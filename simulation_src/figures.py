colornames = ["red", "blue","green","purple","yellow","cyan","orange","brown","pink","teal"]
object_names = ['airplane', 'bird', 'car', 'cat', 'dog', 'duck', 'frog', 'horse', 'sailboat', 'truck', 'clock', 'umbrella']
emnist_labels = ['0','1','2','3','4','5','6','7','8','9','A','B','C','D','E','F','G','H','I','J','K','L','M','N','O','P','Q','R','S','T','U','V','W','X','Y','Z']
DATASET_ROOT = '/home/bwyble/data/'
quickdraw_target_set = [0,2,8,10,11]

# prerequisites
import torch
import sys
import os
from collections import defaultdict
import torch.nn.functional as F
import torchvision.transforms.functional as Ft
from PIL import Image, ImageDraw, ImageFont
import matplotlib.pyplot as plt
import matplotlib as mpl
from torchvision import datasets, transforms
from torchvision.utils import save_image
import math
from scipy import stats
import gc
from PIL import Image
from itertools import cycle
from MLR_src.dataset_builder import Colorize_specific
import numpy as npy
import seaborn as sns
import joblib
import inspect

#internal imports
sys.path.append(os.path.dirname(os.path.dirname(os.path.abspath(__file__))))
from MLR_src.dataset_builder import Dataset, Colorize_specific
from MLR_src.mVAE import VAE_CNN
from MLR_src.BP_functions import BPTokens_binding_all, BPTokens_retrieveByToken, BPTokens_storage, BPTokens_with_labels, BPTokens_storage_bitmask, BPTokens_retrieveByToken_bitmask
from MLR_src.label_network import s_classes, VAEshapelabels
from training_constants import text_to_tensor
import random


from PIL import Image, ImageOps, ImageEnhance#, __version__ as PILLOW_VERSION
convert_tensor = transforms.ToTensor()
convert_image = transforms.ToPILImage()

if torch.cuda.is_available():
    device = torch.device('cuda')
    print('CUDA')
else:
    device = 'cpu'

bs_testing = 1000     # number of images for testing. 20000 is the limit
shape_coeff = 1       #cofficient of the shape map
color_coeff = 1       #coefficient of the color map
location_coeff = 0    #Coefficient of Location map
l1_coeff = 1          #coefficient of layer 1
l2_coeff = 1          #coefficient of layer 2
shapeLabel_coeff= 1   #coefficient of the shape label
colorLabel_coeff = 1  #coefficient of the color label
location_coeff = 0  #coefficient of the color label

bpsize = 10000#00         #size of the binding pool
token_overlap =0.1
bpPortion = int(token_overlap *bpsize) # number binding pool neurons used for each item

normalize_fact_familiar=1
normalize_fact_novel=1


imgsize = 28
BP_std = 0

# helper functions:
def log_function_name():
    return inspect.stack()[1].function

def location_to_onehot(locations):
    pass

def onehot_to_location(onehots):
    pass

def sync_devices(tensor_list):
    # uses 0th element device as the target device for all tensors in the list
    # if 2d list, will recursively sync all tensors in the list to the 0th element device of the 0th list

    if isinstance(tensor_list, list) and isinstance(tensor_list[0], list):
        target_device = tensor_list[0][0].device
        synced_tensors = [[tensor.to(target_device) for tensor in sublist] for sublist in tensor_list]
    else:
        target_device = tensor_list[0].device
        synced_tensors = [tensor.to(target_device) for tensor in tensor_list]
    return synced_tensors

def compute_correlation(x, y):
    assert x.shape == y.shape, "Tensors must have the same shape"
    
    # Flatten tensors if they're multidimensional
    x = x.view(-1)
    y = y.view(-1)
    #x = replace_near_zero(x)
    #y = replace_near_zero(y)
    
    # Compute means
    x_mean = torch.mean(x)
    y_mean = torch.mean(y)
    
    # Compute the numerator
    numerator = torch.sum((x - x_mean) * (y - y_mean))
    
    # Compute the denominator
    x_var = torch.sum((x - x_mean)**2)
    y_var = torch.sum((y - y_mean)**2)
    denominator = torch.sqrt(x_var * y_var)
    
    # Compute correlation
    correlation = numerator / denominator
    
    return correlation

def zero_outside_radius(tensor, center_x, center_y, radius=6):
    result = tensor.clone()
    center_x = (28*center_x)/500
    center_y = (28*center_y)/500
    
    # Iterate over all positions in the 28x28 grid
    for i in range(28):
        for j in range(28):
            # Calculate the squared distance from the current position to the center
            distance_squared = (i - center_y)**2 + (j - center_x)**2
            
            # If the distance is greater than the radius, set all channel values to zero
            if distance_squared > radius**2:
                result[:, i, j] = 0
    
    return result

def build_single(input_tensor):
    # input_tensor: [x, batch_size, channels, height, width]
    output_tensor = input_tensor.sum(dim=1)  # sum across frames
    output_tensor = torch.clamp(output_tensor, min=0.0, max=1.0)
    return output_tensor

# figures:

def simultaneous_encode(vae: VAE_CNN, data, folder_path, x):
    bpsize = 6500         #size of the binding pool
    token_overlap = 0.2
    bpPortion = int(token_overlap *bpsize)
    n = len(data)
    mse_list = []
    recon_list = []
    for i in range(n):
        activations = vae.activations(data[i].view(-1,3,28,28), False)

        BP_activations = {'l1': [activations['skip'].view(1,-1), 1]}

        # store and retrieve
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations, 1,normalize_fact_novel)
        BP_activations_out = BPTokens_retrieveByToken(bpsize, bpPortion, BPOut, Tokenbindings, BP_activations, 1,normalize_fact_novel)
        l1_out = BP_activations_out['l1']

        recon = vae.decoder_skip_cropped(0, 0, 0, l1_out.view(1,-1))
        recon_list += [recon]
    
    save_image(torch.cat([data[:8], torch.cat(recon_list[:8])]), f'{folder_path}{x}_simultaneous.png', nrow=8, pad_value=0.6, normalize=False)
    return 0

def sequential_encode(vae: VAE_CNN, original, frames, folder_path, probe_x, input_x=6):
    bpsize = 6500         #size of the binding pool
    token_overlap = 0.2
    bpPortion = int(token_overlap *bpsize)
    # data: N,x,3,28,28  N: batch size, x: frames per item
    n = frames.size(0)
    input_x = probe_x
    mse_list = []
    recon_list = []
    probe_list = []
    for i in range(n):
        activations = vae.activations(frames[i][:probe_x].view(-1,3,28,28), True)

        BP_activations = {'shape': [activations['shape'].view(probe_x,-1), 1], 'color': [activations['color'].view(probe_x,-1), 1], } # 2 familiar in shape/color

        # store and retrieve
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations, probe_x,normalize_fact_novel)
        BP_activations_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations, probe_x,normalize_fact_novel)
        shape_out, color_out = BP_activations_out['shape'], BP_activations_out['color']        
        pre_retinal_frames = vae.decoder_cropped(activations['shape'].view(probe_x,-1), activations['color'].view(probe_x,-1),0,0)

        pre_BP_recon_frames = vae.decoder_retinal(activations['shape'].view(probe_x,-1), activations['color'].view(probe_x,-1), activations['theta'])
        pre_BP_recon_frames = F.interpolate(pre_BP_recon_frames, size=(28, 28), mode='bilinear', align_corners=False)
        
        recon_frames = vae.decoder_retinal(shape_out, color_out, activations['theta'])
        recon_frames = F.interpolate(recon_frames, size=(28, 28), mode='bilinear', align_corners=False)
        
        recon = build_single(recon_frames.view(1,probe_x,3,28,28)).view(1,3,28,28)
        probe = build_single(frames[i][:probe_x].view(1,probe_x,3,28,28)).view(1,3,28,28)
        recon_list += [recon]
        probe_list += [probe]


    save_image(torch.cat([frames[i].view(-1,3,28,28), pre_retinal_frames, pre_BP_recon_frames, recon_frames]), f'{folder_path}{probe_x}_sequential_frames.png', nrow=probe_x, pad_value=0.6, normalize=False)
    save_image(torch.cat([torch.cat(probe_list[:8]), torch.cat(recon_list[:8])]), f'{folder_path}{probe_x}_sequential.png', nrow=8, pad_value=0.6, normalize=False)

    return 0

@torch.no_grad()
def fig_simultaneous_vs_sequential_1(vae: VAE_CNN, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    vae.eval()
    folder_path += '1/'

    print('generating Figure simultaneous vs sequential plot (1, 3, 6)')

    square_data_1 = torch.load(f'{DATASET_ROOT}/color_square_data/original_1_color.pth', 'cuda:1')[:40]
    square_data_3 = torch.load(f'{DATASET_ROOT}/color_square_data/original_3_color.pth', 'cuda:1')[:40]
    #square_data_3_frames = torch.load(f'{DATASET_ROOT}/color_square_data/original_frames_3_color.pth', 'cuda:1')
    square_data_6 = torch.load(f'{DATASET_ROOT}/color_square_data/original_6_color.pth', 'cuda:1')[:40]
    square_data_6_frames = torch.load(f'{DATASET_ROOT}/color_square_data/original_frames_6_color.pth', 'cuda:1')[:40]
    square_data_6_positions = torch.load(f'{DATASET_ROOT}/color_square_data/positions_6_color.pth', 'cuda:1')[:40]
    print(square_data_6_positions[0])
    #print(square_data_3_frames.size()) # N,3,3,28,28

    mse_data = {}
    # store 6 items simultaneously/sequentially
    mse_data['mse_simultaneous_6'] = simultaneous_encode(vae, square_data_6, folder_path, 6)
    print(mse_data)
    mse_data['mse_sequential_6'] = sequential_encode(vae, square_data_6, square_data_6_frames, folder_path, 6)
    print(mse_data)
    # store 3 items sequentially
    mse_data['mse_simultaneous_3'] = simultaneous_encode(vae, square_data_3, folder_path, 3)
    mse_data['mse_sequential_3'] = sequential_encode(vae, square_data_6, square_data_6_frames, folder_path, 3)

    # store 1 item
    mse_data['mse_simultaneous_1'] = simultaneous_encode(vae, square_data_1, folder_path, 1)
    mse_data['mse_sequential_1'] = sequential_encode(vae, square_data_6, square_data_6_frames, folder_path, 1)

    print(mse_data)

@torch.no_grad()
def fig_simultaneous_vs_sequential(vae: VAE_CNN, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    vae.eval()
    bpsize = 13500         #size of the binding pool
    token_overlap = 0.15
    bpPortion = int(token_overlap *bpsize)


    print('generating Figure simultaneous vs sequential change detection')
    t = 200
    square_data_6 = torch.load(f'{DATASET_ROOT}/color_square_data/original_6_color.pth', 'cuda:1')[:t]
    square_data_6_frames = torch.load(f'{DATASET_ROOT}/color_square_data/original_frames_6_color.pth', 'cuda:1')[:t]
    square_data_6_change = torch.load(f'{DATASET_ROOT}/color_square_data/change_frames_6_color.pth', 'cuda:1')[:t]  # changed scenes
    square_data_6_positions = torch.load(f'{DATASET_ROOT}/color_square_data/positions_6_color.pth', 'cuda:1')[:t]

    def compute_correlation(x, y):
        x, y = x.view(-1), y.view(-1)
        x_mean, y_mean = torch.mean(x), torch.mean(y)
        numerator = torch.sum((x - x_mean) * (y - y_mean))
        denominator = torch.sqrt(torch.sum((x - x_mean)**2) * torch.sum((y - y_mean)**2))
        return (numerator / denominator).item()

    def compute_dprime(no_change_vector, change_vector):
        hit_rate = npy.clip(npy.mean(change_vector), 0.01, 0.99)
        false_alarm_rate = npy.clip(1 - npy.mean(no_change_vector), 0.01, 0.99)
        return stats.norm.ppf(hit_rate) - stats.norm.ppf(false_alarm_rate)

    def run_change_detection(recon_list, original_list, change_list, threshold):
        """
        recon_list:    list of BP-reconstructed tensors (memory)
        original_list: list of original scene tensors  (no-change probe)
        change_list:   list of changed scene tensors   (change probe)
        threshold:     scalar decision boundary
        Returns accuracy and d-prime.
        """
        recon_list, original_list, change_list = sync_devices([recon_list, original_list, change_list])
        no_change_detected, change_detected = [], []
        r_original_all, r_change_all = [], []

        for recon, orig, chng in zip(recon_list, original_list, change_list):
            r_orig = compute_correlation(recon, orig)
            r_chng = compute_correlation(recon, chng)
            r_original_all.append(r_orig)
            r_change_all.append(r_chng)

            no_change_detected.append(1 if r_orig > threshold else 0)
            change_detected.append(1 if r_chng <= threshold else 0)

        accuracy = (
            (sum(no_change_detected) / len(no_change_detected)) +
            (sum(change_detected)    / len(change_detected))
        ) / 2
        dprime = compute_dprime(no_change_detected, change_detected)
        avg_r = (npy.mean(r_original_all), npy.mean(r_change_all))
        return accuracy, dprime, avg_r

    def get_simultaneous_recons(data, frames, probe_x, positions):
        recon_list, original_list = [], []
        for i in range(len(data)):
            act = vae.activations(data[i].view(-1, 3, 28, 28), False)
            BP_act = {'l1': [act['skip'].view(1, -1), 1]}
            BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_act, 1, normalize_fact_novel)
            BP_act_out = BPTokens_retrieveByToken(bpsize, bpPortion, BPOut, Tokenbindings, BP_act, 1, normalize_fact_novel)
            recon = vae.decoder_skip_cropped(0, 0, 0, BP_act_out['l1'].view(1, -1))
            recon_list.append(recon.squeeze(0))
            probe = build_single(frames[i][:probe_x].view(1, probe_x, 3, 28, 28)).squeeze(0)
            original_list.append(probe)
            #original_list.append(data[i].view(3, 28, 28))
            
        save_image(torch.cat(sync_devices([data[:8].view(8,3,28,28), torch.cat(recon_list[:8]).view(8,3,28,28)])), f'{folder_path}{probe_x}_simultaneous.png', nrow=8, pad_value=0.6, normalize=False)
    
        
        if probe_x == 1:
            for i in range(len(recon_list)):
                recon_list[i] = zero_outside_radius(recon_list[i], positions[i][0][0], positions[i][0][1], radius=6)
                #original_list[i] = zero_outside_radius(original_list[i], positions[i][0][0], positions[i][0][1], radius=6)
        return recon_list, original_list

    def get_sequential_recons(frames, probe_x, input_x=5):
        recon_list, original_list = [], []
        n = frames.size(0)
        for i in range(n):
            act = vae.activations(frames[i][:input_x].view(-1, 3, 28, 28), True)
            
            # always store all 6
            BP_act = {
                'shape': [act['shape'].view(input_x, -1), 0],
                'color': [act['color'].view(input_x, -1), 1],
            }
            BPOut, Tokenbindings = BPTokens_storage(
                bpsize, bpPortion, BP_act, input_x, normalize_fact_novel
            )
            
            # retrieve only probe_x items
            BP_act_probe = {
                'shape': [act['shape'].view(input_x, -1)[:min(probe_x, input_x)], 0],
                'color': [act['color'].view(input_x, -1)[:min(probe_x, input_x)], 1],
            }
            BP_act_out = BPTokens_retrieveByToken(
                bpsize, bpPortion, BPOut, Tokenbindings, BP_act_probe, min(probe_x, input_x), normalize_fact_novel
            )
            
            shape_out, color_out = BP_act_out['shape'], BP_act_out['color']
            recon_frames = vae.decoder_retinal(shape_out, color_out, act['theta'][:min(probe_x, input_x)])
            recon_frames = F.interpolate(recon_frames, size=(28, 28), mode='bilinear', align_corners=False)
            recon = build_single(recon_frames.view(1, min(probe_x, input_x), 3, 28, 28)).squeeze(0)
            probe = build_single(frames[i][:probe_x].view(1, probe_x, 3, 28, 28)).squeeze(0)
            recon_list.append(recon)
            original_list.append(probe)

        #save_image(torch.cat([frames[i].view(-1,3,28,28), pre_retinal_frames, pre_BP_recon_frames, recon_frames]), f'{folder_path}{probe_x}_sequential_frames.png', nrow=probe_x, pad_value=0.6, normalize=False)
        save_image(torch.cat(sync_devices([torch.cat(original_list[:8]).view(8,3,28,28), torch.cat(recon_list[:8]).view(8,3,28,28)])), f'{folder_path}{probe_x}_sequential.png', nrow=8, pad_value=0.6, normalize=False)

        return recon_list, original_list

    def get_change_probes(change_frames, probe_x):
        """Collapse change frames the same way get_sequential_recons collapses originals."""
        probe_list = []
        for i in range(change_frames.size(0)):
            probe = build_single(change_frames[i][:probe_x].view(1, probe_x, 3, 28, 28)).squeeze(0)
            probe_list.append(probe)
        return probe_list

    # derive a threshold from the correlation midpoint
    def midpoint_threshold(recon_list, original_list, change_list):
        recon_list, original_list, change_list = sync_devices([recon_list, original_list, change_list])
        r_orig = npy.mean([compute_correlation(r, o) for r, o in zip(recon_list, original_list)])
        r_chng = npy.mean([compute_correlation(r, c) for r, c in zip(recon_list, change_list)])
        return (r_orig + r_chng) / 2

    if not load_data:
        results = {}

        for probe_x in [1, 3, 6]:
            sim_recons, sim_originals          = get_simultaneous_recons(square_data_6, square_data_6_frames, probe_x, square_data_6_positions)
            sim_changes                        = get_change_probes(square_data_6_change, probe_x)
            sim_thresh                         = midpoint_threshold(sim_recons, sim_originals, sim_changes)
            acc, dp, avg_r                     = run_change_detection(sim_recons, sim_originals, sim_changes, sim_thresh)
            results[f'simultaneous_{probe_x}']          = {'accuracy': acc, 'dprime': dp, 'r': avg_r}

            seq_recons, seq_originals      = get_sequential_recons(square_data_6_frames, probe_x, probe_x)
            seq_changes                    = get_change_probes(square_data_6_change, probe_x)
            seq_thresh                     = midpoint_threshold(seq_recons, seq_originals, seq_changes)
            acc, dp, avg_r                 = run_change_detection(seq_recons, seq_originals, seq_changes, seq_thresh)
            results[f'sequential_{probe_x}'] = {'accuracy': acc, 'dprime': dp, 'r': avg_r}
        
        print(results)
        joblib.dump(results, pkl_path)

    else:
        results = joblib.load(pkl_path)

    mpl.rcParams['axes.titlesize']  = 16
    mpl.rcParams['axes.labelsize']  = 15
    mpl.rcParams['xtick.labelsize'] = 15
    mpl.rcParams['ytick.labelsize'] = 15
    mpl.rcParams['legend.fontsize'] = 13
    probe_sizes = [1, 3, 6]
    x = npy.arange(len(probe_sizes))
    bar_width = 0.35

    # d-prime
    fig, ax = plt.subplots(figsize=(8, 6))
    sim_dprimes = [results[f'simultaneous_{p}']['dprime'] for p in probe_sizes]
    seq_dprimes = [results[f'sequential_{p}']['dprime']   for p in probe_sizes]
    ax.bar(x - bar_width/2, sim_dprimes, width=bar_width, label='simultaneous')
    ax.bar(x + bar_width/2, seq_dprimes, width=bar_width, label='sequential')
    ax.set_xticks(x); ax.set_xticklabels(probe_sizes)
    ax.set_xlabel('probe set size')
    ax.set_ylabel("d'")
    ax.set_title("d' — simultaneous vs sequential change detection")
    ax.legend()
    plt.tight_layout()
    plt.savefig(f'{folder_path}cd_sim_vs_seq_dprime.png')
    plt.close()

    # accuracy
    fig, ax = plt.subplots(figsize=(8, 6))
    sim_acc = [results[f'simultaneous_{p}']['accuracy'] for p in probe_sizes]
    seq_acc = [results[f'sequential_{p}']['accuracy']   for p in probe_sizes]
    ax.bar(x - bar_width/2, sim_acc, width=bar_width, label='simultaneous')
    ax.bar(x + bar_width/2, seq_acc, width=bar_width, label='sequential')
    ax.set_xticks(x); ax.set_xticklabels(probe_sizes)
    ax.set_xlabel('probe set size')
    ax.set_ylabel('accuracy')
    ax.set_title('Accuracy — simultaneous vs sequential change detection')
    ax.legend()
    plt.tight_layout()
    plt.savefig(f'{folder_path}cd_sim_vs_seq_accuracy.png')
    plt.close()

    # correlation — 4 bars per group: sim no-change, sim change, seq no-change, seq change
    fig, ax = plt.subplots(figsize=(10, 6))
    offsets = [-1.5, -0.5, 0.5, 1.5]
    gap = bar_width * 0.8
    sim_r_orig = [results[f'simultaneous_{p}']['r'][0] for p in probe_sizes]
    sim_r_chng = [results[f'simultaneous_{p}']['r'][1] for p in probe_sizes]
    seq_r_orig = [results[f'sequential_{p}']['r'][0]   for p in probe_sizes]
    seq_r_chng = [results[f'sequential_{p}']['r'][1]   for p in probe_sizes]
    ax.bar(x + offsets[0]*gap, sim_r_orig, width=bar_width*0.8, label='sim — no change')
    ax.bar(x + offsets[1]*gap, sim_r_chng, width=bar_width*0.8, label='sim — change')
    ax.bar(x + offsets[2]*gap, seq_r_orig, width=bar_width*0.8, label='seq — no change')
    ax.bar(x + offsets[3]*gap, seq_r_chng, width=bar_width*0.8, label='seq — change')
    ax.set_xticks(x); ax.set_xticklabels(probe_sizes)
    ax.set_xlabel('probe set size')
    ax.set_ylabel('r')
    ax.set_title('Correlation — simultaneous vs sequential')
    ax.legend()
    plt.tight_layout()
    plt.savefig(f'{folder_path}cd_sim_vs_seq_r.png')
    plt.close()

@torch.no_grad()
def fig_efficient_rep(vae: VAE_CNN, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    vae.eval()

    if load_data is False:
        print('generating Figure efficient reconstruction plot')
        retina_size = 100
        imgsize = 28
        bpsize = 10000         #size of the binding pool
        token_overlap = 0.15
        bpPortion = int(token_overlap *bpsize) # number binding pool neurons used for each item
        numimg = 7
        n_2 = 1
        n_4 = 4
        #make the data loader
        test_loader_mnist = Dataset('mnist',{'colorize':True}, train=True).get_loader(numimg)
        #test_loader_emnist = Dataset('emnist',{'colorize':True}, train=True).get_loader(numimg)
        test_loader_emnist = Dataset('emnist',{'retina':False, 'colorize':True, 'rotate':False, 'scale':True, 'target_set':[0, 1, 2, 3, 4, 15]}, train=True).get_loader(numimg)
        #load in some examples of Bengali Characters
        '''for i in range (1,7):
            color = Colorize_specific(random.randint(0,9))
            img = Image.open(f'data/current_bengali/{i}_thick.png')
            img_new = convert_tensor(color(img))
            
            all_imgs.append(img_new)
        all_imgs = torch.stack(all_imgs)
        imgs = all_imgs.view(-1, 3, imgsize, imgsize).cuda()   ''' 

        dataiter_mnist = iter(test_loader_mnist)
        dataiter_emnist = iter(test_loader_emnist)
        sc_2 = []
        l1_2 = []
        sc_4 = []
        l1_4 = []

        for count in range(0,100):
            data_mnist, labels = next(dataiter_mnist)
            data_emnist, labels = next(dataiter_emnist)
            #data_emnist = imgs # Bengali chars not emnist
            
            mnist_sample = data_mnist[:n_4].cuda()
            emnist_sample = data_emnist[:n_4].cuda()
            
            #push the images through the model
            mnist_act = vae.activations(mnist_sample.view(-1,3,28,28), False)
            emnist_act = vae.activations(emnist_sample.view(-1,3,28,28), False)
            
            emnist_shape_act = emnist_act['shape']
            emnist_color_act = emnist_act['color']

            mnist_l1_act = mnist_act['skip']

            BP_activations_sc_2 = {'shape': [emnist_shape_act[:n_2].view(n_2,-1), 1], 'color': [emnist_color_act[:n_2].view(n_2,-1), 1]} # 2 familiar in shape/color
            BP_activations_l1_2 = {'l1': [mnist_l1_act[:n_2].view(n_2,-1), 1]} # 2 novel in L1

            BP_activations_sc_4 = {'shape': [emnist_shape_act.view(n_4,-1), 1], 'color': [emnist_color_act.view(n_4,-1), 1]} # 4 familiar in shape/color
            BP_activations_l1_4 = {'l1': [mnist_l1_act.view(n_4,-1), 1]} # 4 novel in L1

            # store and retrieve 2 familiar s/c maps
            BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_sc_2, n_2,normalize_fact_novel)
            BP_activations_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_sc_2, n_2,normalize_fact_novel)
            shape_out_2, color_out_2 = BP_activations_out['shape'], BP_activations_out['color']

            # store and retrieve 2 novel l1 act
            BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_l1_2, n_2,normalize_fact_novel)
            BP_activations_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_l1_2, n_2,normalize_fact_novel)
            l1_out_2 = BP_activations_out['l1']

            # store and retrieve 4 familiar s/c maps
            BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_sc_4, n_4,normalize_fact_novel)
            BP_activations_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_sc_4, n_4,normalize_fact_novel)
            shape_out_4, color_out_4 = BP_activations_out['shape'], BP_activations_out['color']

            # store and retrieve 4 novel l1 act
            BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_l1_4, n_4,normalize_fact_novel)
            BP_activations_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_l1_4, n_4,normalize_fact_novel)
            l1_out_4 = BP_activations_out['l1']
            
            recon_sc_2 = vae.decoder_cropped(shape_out_2, color_out_2,0,0).cuda() #rgb_to_gray(vae.decoder_shape(shape_out_2, 0))#
            recon_l1_2 = vae.decoder_skip_cropped(0, 0, 0, l1_out_2).cuda()

            recon_sc_4 = vae.decoder_cropped(shape_out_4, color_out_4,0,0).cuda() #rgb_to_gray(vae.decoder_shape(shape_out_4, 0))#
            recon_l1_4 = vae.decoder_skip_cropped(0, 0, 0, l1_out_4).cuda()
            
            corr_sc_2 = compute_correlation(emnist_sample[:n_2], recon_sc_2).item()
            corr_l1_2 = compute_correlation(mnist_sample[:n_2], recon_l1_2).item()

            corr_sc_4 = compute_correlation(emnist_sample, recon_sc_4).item()
            corr_l1_4 = compute_correlation(mnist_sample, recon_l1_4).item()

            sc_2 += [corr_sc_2]
            l1_2 += [corr_l1_2]

            sc_4 += [corr_sc_4]
            l1_4 += [corr_l1_4]

        corr_sc_2 = sum(sc_2)/len(sc_2)
        corr_l1_2 = sum(l1_2)/len(l1_2)

        corr_sc_4 = sum(sc_4)/len(sc_4)
        corr_l1_4 = sum(l1_4)/len(l1_4)

        print(corr_l1_2, corr_l1_4)
        print(corr_sc_2, corr_sc_4)

        e = torch.zeros((1,3,28,28)).cuda()
        fig_data = [mnist_sample, torch.cat([recon_sc_2, e, e, e], 0), recon_sc_4, emnist_sample,
                   torch.cat([recon_l1_2, e, e, e], 0), recon_l1_4,]

        data_to_pickle = {
            "fig_data": fig_data,
            "n_2": n_2,
            "n_4": n_4,
            "corr_l1_2": corr_l1_2,
            "corr_l1_4": corr_l1_4,
            "corr_sc_2": corr_sc_2,
            "corr_sc_4": corr_sc_4,
        }

        joblib.dump(data_to_pickle, pkl_path)

    else:
        if not os.path.exists(pkl_path):
            raise Exception(f"No data exists for plot: {folder_path}{log_function_name()}")
        
        # load plotting data
        loaded_data = joblib.load(pkl_path)
        n_2 = loaded_data["n_2"]
        n_4 = loaded_data["n_4"]
        corr_l1_2 = loaded_data["corr_l1_2"]
        corr_l1_4 = loaded_data["corr_l1_4"]
        corr_sc_2 = loaded_data["corr_sc_2"]
        corr_sc_4 = loaded_data["corr_sc_4"]

    save_image(
        torch.cat(fig_data, 0),
        f'{folder_path}efficient_recon_sample_ss2_ss4.png', pad_value=0.6,
        nrow=n_4, normalize=False)

    plt.figure()

    sns.lineplot(
        x=[n_2, n_4],
        y=[corr_l1_2, corr_l1_4],
        label='novel images (L1)'
    )

    sns.lineplot(
        x=[n_2, n_4],
        y=[corr_sc_2, corr_sc_4],
        label='familiar images (feature maps)'
    )

    plt.xlabel('set size')
    plt.ylabel('r')
    plt.title('Set Size vs. Reconstruction Correlation')
    plt.legend()

    plt.savefig(f'{folder_path}efficient_recon.png')
    plt.close()

@torch.no_grad()
def fig_repeat_recon(vae: VAE_CNN, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'

    vae.eval()
    print('generating Figure repeated reconstructions, green 5, red 5, red 3')
    retina_size = 100
    imgsize = 28
    bpPortion = int(token_overlap *bpsize) # number binding pool neurons used for each item
    numimg = 3  #how many objects will we use here?
    #torch.set_default_dtype(torch.float64)
    #make the data loader, but specifically we are creating stimuli on the opposite to how the model was trained
    test_loader_noSkip = Dataset('emnist',{'colorize':False}, train=True).get_loader(numimg)

    dataiter_noSkip = iter(test_loader_noSkip)
    data, labels = next(dataiter_noSkip)
    data = data #.cuda()

    # find 2 5's and then 1 3
    imgs = []
    c = 0
    while c < 2:
        if labels[0][0].item() == 11:
            imgs += [data[0]]
            c += 1
        data, labels = next(dataiter_noSkip)
    
    c = 0
    while c < 1:
        if labels[0][0].item() == 12:
            imgs += [data[0]]
            c += 1
        data, labels = next(dataiter_noSkip)
    
    red = Colorize_specific(0)
    
    green = Colorize_specific(1)
    blue = Colorize_specific(2)

    imgs[0] = convert_tensor(red(convert_image(imgs[0])))
    imgs[1] = convert_tensor(green(convert_image(imgs[1])))
    imgs[2] = convert_tensor(blue(convert_image(imgs[2])))

    sample = torch.cat(imgs, 0).cuda()
    
    #push the images through the model
    activations = vae.activations(sample.view(-1,3,28,28), False)
    l1_act = activations['skip']
    shape_act = activations['shape']
    color_act = activations['color']
    reconb = vae.decoder_cropped(shape_act, color_act, 0)

    mu_shape, _, mu_color, _, hskip = vae.encoder(sample.view(-1,3,28,28))

    #    sample = torch.cat(imgs, 0).cuda()
    #sample = torch.stack(imgs, 0).cuda()
    #with torch.no_grad():
    #    reconb, _, _, _, _, _, _ = vae(sample, 'cropped', ['shape', 'color'])
    

    reconskip = vae.decoder_skip_cropped(0, 0, 0, l1_act.view(numimg,-1))
    #reconskip, mu_color, log_var_color, mu_shape, log_var_shape = vae.forward_layers(l1_act.view(numimg,-1), l2_act, 3, 'skip_cropped') 

    emptyshape = torch.empty((1,3,28,28)).cuda()
    imgmatrixMap = torch.cat([sample.view(numimg,3,28,28).cuda(), reconb],0)
    imgmatrixL1 = torch.cat([sample.view(numimg,3,28,28).cuda(), reconskip],0)
    shape_act_in = shape_act

    BP_activations_sc = {'shape': [shape_act.view(numimg,-1), 1], 'color': [color_act.view(numimg,-1), 1]}
    BP_activations_l1 = {'l1': [l1_act.view(numimg,-1), 1]}
    
    emptyshape = torch.zeros((1,3,28,28)).cuda()
    
    # Row 1: originals (already in imgmatrixMap and imgmatrixL1)
    # Row 2: direct recon (already in imgmatrixMap and imgmatrixL1)
    
    # Rows 3+: BP recon at set sizes 1 through numimg
    for n in range(1, numimg+1):
        # Store and retrieve shape+color maps
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_sc, n, normalize_fact_novel)
        BP_activations_out = BPTokens_retrieveByToken(bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_sc, n, normalize_fact_novel)
        shape_out_all, color_out_all = BP_activations_out['shape'], BP_activations_out['color']
        retrievals = vae.decoder_cropped(shape_out_all, color_out_all, 0, 0).cuda()
        
        # Store and retrieve L1
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_l1, n, normalize_fact_novel)
        BP_activations_out = BPTokens_retrieveByToken(bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_l1, n, normalize_fact_novel)
        l1_out_all = BP_activations_out['l1']
        recon_layer1_skip = vae.decoder_skip_cropped(0, 0, 0, l1_out_all.view(n, -1))
        
        # Append retrievals, pad with empty images for items not stored
        imgmatrixMap = torch.cat([imgmatrixMap, retrievals], 0)
        imgmatrixL1 = torch.cat([imgmatrixL1, recon_layer1_skip], 0)
        
        for i in range(n, numimg):
            imgmatrixMap = torch.cat([imgmatrixMap, emptyshape], 0)
            imgmatrixL1 = torch.cat([imgmatrixL1, emptyshape], 0)
    
    save_image(imgmatrixL1, f'{folder_path}figure_repeat_L1.png', nrow=numimg, normalize=False, pad_value=0.6)
    save_image(imgmatrixMap, f'{folder_path}figure_repeat_Map.png', nrow=numimg, normalize=False, pad_value=0.6)


@torch.no_grad()
def fig_non_repeat_recon(vae: VAE_CNN, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'

    vae.eval()
    print('generating Figure repeated reconstructions, green 5, red 5, red 3')
    retina_size = 100
    imgsize = 28
    bpPortion = int(token_overlap *bpsize) # number binding pool neurons used for each item
    numimg = 3  #how many objects will we use here?
    #torch.set_default_dtype(torch.float64)
    #make the data loader, but specifically we are creating stimuli on the opposite to how the model was trained
    test_loader_noSkip= Dataset('emnist',{'colorize':False}, train=True).get_loader(numimg)

    dataiter_noSkip = iter(test_loader_noSkip)
    data, labels = next(dataiter_noSkip)
    data = data #.cuda()

    # find 2 5's and then 1 3
    imgs = []
    c = 0
    while c < 1:
        if labels[0][0].item() == 10:
            imgs += [data[0]]
            c += 1
        data, labels = next(dataiter_noSkip)
    c = 0
    while c < 1:
        if labels[0][0].item() == 11:
            imgs += [data[0]]
            c += 1
        data, labels = next(dataiter_noSkip)
    
    c = 0
    while c < 1:
        if labels[0][0].item() == 12:
            imgs += [data[0]]
            c += 1
        data, labels = next(dataiter_noSkip)

    red = Colorize_specific(0)
    
    green = Colorize_specific(1)
    blue = Colorize_specific(2)

    imgs[0] = convert_tensor(red(convert_image(imgs[0])))
    imgs[1] = convert_tensor(green(convert_image(imgs[1])))
    imgs[2] = convert_tensor(blue(convert_image(imgs[2])))

    sample = torch.cat(imgs, 0).cuda()
    
    #push the images through the model
    activations = vae.activations(sample.view(-1,3,28,28), False)
    l1_act = activations['skip']
    shape_act = activations['shape']
    color_act = activations['color']
    reconb = vae.decoder_cropped(shape_act, color_act, 0)

    mu_shape, _, mu_color, _, hskip = vae.encoder(sample.view(-1,3,28,28))

    #    sample = torch.cat(imgs, 0).cuda()
    #sample = torch.stack(imgs, 0).cuda()
    #with torch.no_grad():
    #    reconb, _, _, _, _, _, _ = vae(sample, 'cropped', ['shape', 'color'])
    

    reconskip = vae.decoder_skip_cropped(0, 0, 0, l1_act.view(numimg,-1))
    #reconskip, mu_color, log_var_color, mu_shape, log_var_shape = vae.forward_layers(l1_act.view(numimg,-1), l2_act, 3, 'skip_cropped') 

    emptyshape = torch.empty((1,3,28,28)).cuda()
    imgmatrixMap = torch.cat([sample.view(numimg,3,28,28).cuda(), reconb],0)
    imgmatrixL1 = torch.cat([sample.view(numimg,3,28,28).cuda(), reconskip],0)
    shape_act_in = shape_act

    BP_activations_sc = {'shape': [shape_act.view(numimg,-1), 1], 'color': [color_act.view(numimg,-1), 1]}
    BP_activations_l1 = {'l1': [l1_act.view(numimg,-1), 1]}
    
    emptyshape = torch.zeros((1,3,28,28)).cuda()
    
    # Row 1: originals (already in imgmatrixMap and imgmatrixL1)
    # Row 2: direct recon (already in imgmatrixMap and imgmatrixL1)
    
    # Rows 3+: BP recon at set sizes 1 through numimg
    for n in range(1, numimg+1):
        # Store and retrieve shape+color maps
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_sc, n, normalize_fact_novel)
        BP_activations_out = BPTokens_retrieveByToken(bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_sc, n, normalize_fact_novel)
        shape_out_all, color_out_all = BP_activations_out['shape'], BP_activations_out['color']
        retrievals = vae.decoder_cropped(shape_out_all, color_out_all, 0, 0).cuda()
        
        # Store and retrieve L1
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_l1, n, normalize_fact_novel)
        BP_activations_out = BPTokens_retrieveByToken(bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_l1, n, normalize_fact_novel)
        l1_out_all = BP_activations_out['l1']
        recon_layer1_skip = vae.decoder_skip_cropped(0, 0, 0, l1_out_all.view(n, -1))
        
        # Append retrievals, pad with empty images for items not stored
        imgmatrixMap = torch.cat([imgmatrixMap, retrievals], 0)
        imgmatrixL1 = torch.cat([imgmatrixL1, recon_layer1_skip], 0)
        
        for i in range(n, numimg):
            imgmatrixMap = torch.cat([imgmatrixMap, emptyshape], 0)
            imgmatrixL1 = torch.cat([imgmatrixL1, emptyshape], 0)
    
    save_image(imgmatrixL1, f'{folder_path}figure_non_repeat_L1.png', nrow=numimg, normalize=False, pad_value=0.6)
    save_image(imgmatrixMap, f'{folder_path}figure_non_repeat_Map.png', nrow=numimg, normalize=False, pad_value=0.6)

@torch.no_grad()
def fig_non_color_repeat_recon(vae: VAE_CNN, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'

    vae.eval()
    print('generating Figure repeated reconstructions, any 5, any 5, any 3')
    retina_size = 100
    imgsize = 28
    bpPortion = int(token_overlap *bpsize) # number binding pool neurons used for each item
    numimg = 3  #how many objects will we use here?
    #torch.set_default_dtype(torch.float64)
    #make the data loader, but specifically we are creating stimuli on the opposite to how the model was trained
    test_loader_noSkip= Dataset('emnist',{'colorize':False}, train=True).get_loader(numimg)  

    dataiter_noSkip = iter(test_loader_noSkip)
    data, labels = next(dataiter_noSkip)
    data = data #.cuda()

    # find 2 5's and then 1 3
    imgs = []
    c = 0
    while c < 2:
        if labels[0][0].item() == 15:
            imgs += [data[0]]
            c += 1
        data, labels = next(dataiter_noSkip)
    
    c = 0
    while c < 1:
        if labels[0][0].item() == 13:
            imgs += [data[0]]
            c += 1
        data, labels = next(dataiter_noSkip)
    
    blue = Colorize_specific(random.randint(0,9))
    green = Colorize_specific(random.randint(0,9))
    green1 = Colorize_specific(random.randint(0,9))

    imgs[0] = convert_tensor(blue(convert_image(imgs[0])))
    imgs[1] = convert_tensor(green(convert_image(imgs[1])))
    imgs[2] = convert_tensor(green1(convert_image(imgs[2])))
    
    sample = torch.cat(imgs, 0).cuda()
    
    #push the images through the model
    activations = vae.activations(sample.view(-1,3,28,28), False)
    l1_act = activations['skip']
    shape_act = activations['shape']
    color_act = activations['color']
    reconb = vae.decoder_cropped(shape_act, color_act, 0)

    reconskip = vae.decoder_skip_cropped(0, 0, 0, l1_act.view(numimg,-1))
    #reconskip, mu_color, log_var_color, mu_shape, log_var_shape = vae.forward_layers(l1_act.view(numimg,-1), l2_act, 3, 'skip_cropped') 

    emptyshape = torch.empty((1,3,28,28)).cuda()
    imgmatrixMap = torch.cat([sample.view(numimg,3,28,28).cuda(), reconb],0)
    imgmatrixL1 = torch.cat([sample.view(numimg,3,28,28).cuda(), reconskip],0)
    shape_act_in = shape_act

    BP_activations_sc = {'shape': [shape_act.view(numimg,-1), 1], 'color': [color_act.view(numimg,-1), 1]}
    BP_activations_l1 = {'l1': [l1_act.view(numimg,-1), 1]}
    # store 1 -> numimg items
    for n in range(numimg,numimg+1):
        #Store and retrieve the map versions
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_sc, n,normalize_fact_novel)
        BP_activations_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_sc, n,normalize_fact_novel)
        shape_out_all, color_out_all = BP_activations_out['shape'], BP_activations_out['color']
        z = torch.randn(numimg-n,8).cuda()
        retrievals = vae.decoder_cropped(shape_out_all, color_out_all,0,0).cuda()
        #retrievals = retrievals[:n]
        #Store and retrieve the L1 version
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_l1, n,normalize_fact_novel)
        BP_activations_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_l1, n,normalize_fact_novel)
        #l1_out_all=l1_act[:n] #remove
        l1_out_all = BP_activations_out['l1']
        recon_layer1_skip = vae.decoder_skip_cropped(0, 0, 0, l1_out_all.view(n,-1))

        #imgmatrixMap= torch.cat([imgmatrixMap] + retrievals,0)
        
        imgmatrixMap= torch.cat([imgmatrixMap, retrievals],0)
        imgmatrixL1= torch.cat([imgmatrixL1,recon_layer1_skip],0)

        #now pad with empty images
        for i in range(n,numimg):
            imgmatrixMap= torch.cat([imgmatrixMap,emptyshape*0],0)
            imgmatrixL1= torch.cat([imgmatrixL1,emptyshape*0],0)
    
    save_image(imgmatrixL1, f'{folder_path}figure_non_color_repeat_L1.png',  nrow=numimg,        normalize=False) #range=(-1, 1))
    save_image(imgmatrixMap, f'{folder_path}figure_non_color_repeat_Map.png',  nrow=numimg,        normalize=False) #,range=(-1, 1))

@torch.no_grad()
def percept_concept(vae: VAE_CNN, shape_label, s_classes, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    mnist_loader = Dataset('mnist',{'retina':False, 'colorize':True}, train=True).get_loader(1)
    vals = ['0', '1', '2', '3', '4', '5', '6', '7', '8', '9', 'A', 'B', 'C', 'D', 'E', 'F', 'G', 'H', 'I', 'J', 'K', 'L', 'M', 'N', 'O', 'P', 'Q', 'R', 'S', 'T', 'U', 'V', 'W', 'X', 'Y', 'Z']

    vae.eval()
    label = 8 #35
    percept_label = 3 #7
    print(vals[label])
    data_iter = iter(mnist_loader)
    
    target = 0
    while target != percept_label:
        data = next(data_iter)
        img = data[0][0].cuda()
        target = data[1][0][0].item()
        img = img.view(1,3,28,28)

    # build one hot vectors to be passed to the label networks
    onehot_label = F.one_hot(torch.tensor([label]).cuda(), num_classes=s_classes).float().cuda() # shape

    # generate shape latents from the labels n = noise
    z_shape_labels = shape_label(onehot_label, n = 10)
    activations = vae.activations(img.view(-1,3,28,28), False)
    z_shape_img = activations['shape']
    z_color_img = activations['color']       

    combined_z_shape = (z_shape_labels+z_shape_img)*(1/2)
    print(combined_z_shape.size())

    # pass latents from label network through encoder
    recon_shape_combined = vae.decoder_cropped(combined_z_shape, z_color_img, 0, 0)
    recon_shape_label = vae.decoder_cropped(z_shape_labels, z_color_img, 0, 0)
    
    '''    #comb_img = torch.cat([comb_img, comb_img],0)
    l1,l2,z_shape, z_color, z_location = activations(comb_img)

    pred_ss = clf_shapeS.predict(z_shape.cpu())
    pred_proba = clf_shapeS.predict_proba(z_shape.cpu())

    recon_shape = vae.decoder_shape(z_shape, 0, 0)'''

    save_image(recon_shape_combined,f'{folder_path}percept_concept_{target}-{label}.png') #8B, 8
    save_image(recon_shape_label,f'{folder_path}percept_concept_{label}_label.png')
    save_image(img,f'{folder_path}percept_{target}.png')

    '''    print(pred_ss)
    print(vals[pred_ss[0].item()])'''

@torch.no_grad()
def fig_novel_representations(vae: VAE_CNN, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'

    #from dataset_builder import Colorize_specific
    all_imgs = []
    print('generating Figure 2b, Novel characters retrieved from memory of L1 and Bottleneck')
    retina_size = 100
    imgsize = 28
    numimg = 6
    vae.eval()
    bpsize = 25000#00         #size of the binding pool
    token_overlap =0.9
    bpPortion = int(token_overlap *bpsize) # number binding pool neurons used for each item
    #load in some examples of Bengali Characters
    for i in range (1,numimg+1):
        color = Colorize_specific(random.randint(0,9))
        img = Image.open(f'{DATASET_ROOT}current_bengali/{i}_thick.png')# Image.open(f'change_image_{i}.png') #
        img = img.resize((28, 28))
        img_new = color(img)   # Currently broken, but would add a color to each
        img_new = convert_tensor(img_new)[0:3,:,:]
        #img_new[0] = torch.zeros_like(img_new[0])
        #img_new[2] = torch.zeros_like(img_new[1])

        all_imgs.append(img_new)
    all_imgs = torch.stack(all_imgs)
    imgs = all_imgs.view(-1, 3 * imgsize * imgsize).cuda()
    #location = torch.zeros(imgs.size()[0], vae.l_dim).cuda()
    #location[0] = 1

    blank = torch.zeros(1,3,28,28).cuda()
    blank[:,:,]
    #push the images through the encoder
    activations = vae.activations(imgs.view(-1,3,28,28), False)
    l1_act = activations['skip']
    shape_act = activations['shape']
    color_act = activations['color']

    pre_bp = vae.decoder_skip_cropped(0, 0, 0, l1_act.view(1,-1))

    imgmatrixL1skip  = torch.empty((0,3,28,28)).cuda()
    imgmatrixL1noskip  = torch.empty((0,3,28,28)).cuda()
    imgmatrixMap  = torch.empty((0,3,28,28)).cuda()
    
    
    #now run them through the binding pool!
    #store the items and then retrive them, and do it separately for shape+color maps, then L1, then L2. 
    #first store and retrieve the shape, color and location maps
    for n in range (0,numimg):
            # reconstruct directly from activation
        #recon_layer1_skip, mu_color, log_var_color, mu_shape, log_var_shape = vae.forward_layers(l1_act.view(numimg,-1), l2_act, 3, 'skip_cropped')

        BP_activations_l1 = {'l1': [l1_act[n].view(1,-1), 1]}
        BP_activations_sc = {'shape': [shape_act[n].view(1,-1), 1], 'color': [color_act[n].view(1,-1), 1]}
        
        #now store/retrieve from L1
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_l1, 1,normalize_fact_novel)
        BP_act_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_l1, 1,normalize_fact_novel)
        BP_layerI_out = BP_act_out['l1']
        #print(BP_layerI_out.size())

        BP_layer1_skip = vae.decoder_skip_cropped(0, 0, 0, BP_layerI_out.view(1,-1))

        # reconstruct  from BP version of layer 1, run through the bottleneck
        bn_act = vae.activations(0, False, BP_layerI_out.view(1,-1))
        BP_layer1_noskip = vae.decoder_cropped(bn_act['shape'], bn_act['color'])
        
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_sc, 1,normalize_fact_novel)
        BP_act_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_sc, 1,normalize_fact_novel)
        shape_out_BP, color_out_BP = BP_act_out['shape'], BP_act_out['color']
        #reconstruct from BP version of the shape and color maps
        retrievals = vae.decoder_cropped(shape_out_BP, color_out_BP,0,0).cuda()

        imgmatrixL1skip = torch.cat([imgmatrixL1skip,BP_layer1_skip])
        imgmatrixL1noskip = torch.cat([imgmatrixL1noskip,BP_layer1_noskip])
        imgmatrixMap= torch.cat([imgmatrixMap,retrievals])
    
    store2 = []
    

    #save an image showing:  original images, reconstructions directly from L1,  from L1 BP, from L1 BP through bottleneck, from maps BP
    save_image(torch.cat([imgs[0: numimg].view(numimg, 3, 28, imgsize), pre_bp, imgmatrixL1skip, imgmatrixL1noskip, imgmatrixMap], 0), f'{folder_path}fig_novel_rep.png',
            nrow=numimg,            normalize=False,)

 #TODO: rotated V in an O to form clock, J under rotated D to form an umbrella

@torch.no_grad()
def fig_retinal_mod(vae: VAE_CNN, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'

    vae.eval()
    bs = 10
    mnist_transforms = {'retina':True, 'colorize':True, 'scale':True}
    emnist_loader= Dataset('emnist', mnist_transforms).get_loader(bs)
    
    dataiter_emnist = iter(emnist_loader)
    data, labels = next(dataiter_emnist)
    data = data[0].cuda()

    activations = vae.activations(data, True)
    
    shape = activations['shape']
    color = activations['color']
    scale = activations['scale']
    location = activations['location']

    mod_location = torch.tensor([-0.4, -0.4] * bs).view(bs,2).cuda()
    mod_scale = torch.tensor([0.8] * bs).view(bs,1).cuda()

    theta = torch.cat([scale, location], 1)
    theta_mod_loc = torch.cat([scale, mod_location], 1)
    theta_mod_scale = torch.cat([mod_scale, location], 1)
    theta_mod_both = torch.cat([mod_scale, mod_location], 1)

    recon = vae.decoder_retinal(shape, color, theta)
    recon_mod_loc = vae.decoder_retinal(shape, color, theta_mod_loc)
    recon_mod_scale = vae.decoder_retinal(shape, color, theta_mod_scale)
    recon_mod_both = vae.decoder_retinal(shape, color, theta_mod_both)

    save_image(
        torch.cat([data, recon, recon_mod_scale, recon_mod_loc, recon_mod_both], 0),
        f'{folder_path}figure_retinal_mod.png', pad_value=0.6,
        nrow=bs, normalize=False)

@torch.no_grad()
def recon_test(vae: VAE_CNN, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    vae.eval()
    bpsize = 10000#00         #size of the binding pool
    token_overlap =0.3
    bpPortion = int(token_overlap *bpsize) # number binding pool neurons used for each item

    bs = 10
    device = next(vae.parameters()).device
    
    obj_1_transforms = {'retina':True, 'colorize':True, 'scale':False, 'target_set': quickdraw_target_set,  'location_targets':{(-1,-1):list(range(0,s_classes+1))}}
    obj_1_loader = Dataset('quickdraw', obj_1_transforms).get_loader(bs)

    data, labels = next(iter(obj_1_loader))

    activations = vae.activations(data[0].to(device), True)

    shape_recon = vae.decoder_shape(activations['shape'], 0, 0)
    color_recon = vae.decoder_color(0, activations['color'], 0)
    object_recon = vae.decoder_object(activations['object'], 0, 0)
    skip_recon = vae.decoder_skip_cropped(0, 0, 0, activations['skip'])
    save_image(
        torch.cat([data[1].to(device), skip_recon, object_recon, color_recon, shape_recon], 0),
        f'{folder_path}figure_recon_test.png', pad_value=0.6,
        nrow=bs, normalize=False)

def composite_scene(sample_1, sample_2, sample_3, device):
    def get_mask(img, threshold=0.015):
        img.squeeze_(0)
        r, g, b = img[0:1], img[1:2], img[2:3]
        luminance = 0.2126 * r + 0.7152 * g + 0.0722 * b
        return (luminance > threshold).float()

    comb_img = sample_1.to(device)
    for fg in (sample_2.to(device), sample_3.to(device)):
        mask = get_mask(fg)
        comb_img = comb_img * (1 - mask) + fg * mask

    return torch.clamp(comb_img, 0, 1)

def find_closest_index(val_list, values):
    value = val_list.tolist()
    out = []
    for value in val_list:
        if value in values:
            v = value
        else:
            v = min(values, key=lambda x: (abs(x - value), x))
        out += [v]
    return torch.tensor(out)

def obj_scene_helper(vae, dataloaders, n, save_img, return_loss, bpsize, bpPortion, object_label, color_label, object_classifier, color_classifier, folder_path):
    comb_img_col = []
    obj_recon_no_BP_col = []
    obj_recon_BP_col = []
    obj_recon_label_col = []
    obj_recon_BP_label_col = []
    holistic_no_BP_col = []
    holistic_BP_col = []
    hybrid_col = []
    hybrid_1hot_col = []
    hybrid_bitmask_col = []
    obj_1_loader, obj_2_loader, obj_3_loader, bs = dataloaders
    
    for scene_idx in range(n):
        data_1, labels = next(iter(obj_1_loader))
        data_2, labels = next(iter(obj_2_loader))
        data_3, labels = next(iter(obj_3_loader))

        # add the images together to form a scene
        comb_img = composite_scene(data_1[2], data_2[0], data_3[0], device)
        holistic_comb_img = F.interpolate(comb_img, size=(28, 28), mode='bilinear', align_corners=False)

        activations_1_r = vae.activations(data_1[0], True, None, 'object')
        activations_2_r = vae.activations(data_2[0], True, None, 'object')
        activations_3_r = vae.activations(data_3[0], True, None, 'object')
        activations_1 = vae.activations(data_1[1], False, None, 'object')
        activations_2 = vae.activations(data_2[1], False, None, 'object')
        activations_3 = vae.activations(data_3[1], False, None, 'object')
        activations_1['theta'] = activations_1_r['theta']
        activations_2['theta'] = activations_2_r['theta']
        activations_3['theta'] = activations_3_r['theta']

        holistict_activations = vae.activations(holistic_comb_img, False, None, None)

        obj_1, color_1, theta_1 = activations_1['object'], activations_1['color'], activations_1['theta']
        obj_2, color_2, theta_2 = activations_2['object'], activations_2['color'], activations_2['theta']
        obj_3, color_3, theta_3 = activations_3['object'], activations_3['color'], activations_3['theta']

        objs = torch.cat([obj_1, obj_2, obj_3], 0)
        colors = torch.cat([color_1, color_2, color_3], 0)
        thetas = torch.cat([theta_1, theta_2, theta_3], 0)

        BP_activations = {'object': [objs.view(3, -1), 1],
                        'color': [colors.view(3, -1), 1]}

        # now store/retrieve from object and color maps
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations, 3, normalize_fact_novel)
        BP_act_out = BPTokens_retrieveByToken(bpsize, bpPortion, BPOut, Tokenbindings, BP_activations, 3, normalize_fact_novel)
        BP_obj_out = BP_act_out['object']
        BP_color_out = BP_act_out['color']

        # now store/retrieve via object/color classifications to 1-hot
        pred_objs = object_classifier.predict(objs.cpu())
        pred_colors = color_classifier.predict(colors.cpu())

        object_oneHot = F.one_hot(torch.tensor(pred_objs), num_classes=s_classes).float().to(device)
        color_oneHot = F.one_hot(torch.tensor(pred_colors), num_classes=10).float().to(device)

        BP_activations_oneHot = {'object': [object_oneHot.view(3, -1), 1],
                                'color': [color_oneHot.view(3, -1), 1]}

        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_oneHot, 3, normalize_fact_novel)
        BP_act_out = BPTokens_retrieveByToken(bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_oneHot, 3, normalize_fact_novel)
        BP_obj_out_label = BP_act_out['object']
        BP_color_out_label = BP_act_out['color']

        # remove noise from BP output by converting back to 1-hot
        BP_obj_indices = torch.argmax(BP_obj_out_label, dim=-1)
        BP_color_indices = torch.argmax(BP_color_out_label, dim=-1)
        BP_obj_indices = find_closest_index(BP_obj_indices, [0, 2, 8, 10, 11])
        BP_obj_out_label = F.one_hot(BP_obj_indices, num_classes=BP_obj_out_label.size(-1)).to(device).float()
        BP_color_out_label = F.one_hot(BP_color_indices, num_classes=BP_color_out_label.size(-1)).to(device).float()

        obj_from_BP_label = object_label(BP_obj_out_label, 1)
        color_from_BP_label = color_label(BP_color_out_label, 1)
        obj_from_label = object_label(object_oneHot, 1)
        color_from_label = color_label(color_oneHot, 1)

        # holistic BP
        BP_activations = {'l1': [holistict_activations['skip'], 1]}

        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations, 1, normalize_fact_novel)
        BP_act_out = BPTokens_retrieveByToken(bpsize, bpPortion, BPOut, Tokenbindings, BP_activations, 1, normalize_fact_novel)
        BP_l1_out = BP_act_out['l1']

        # hybrid holistic bg + object_latent:
        BP_activations = {'object': [objs.view(3, -1), 1],
                            'color': [colors.view(3, -1), 1],
                            'l1': [holistict_activations['skip'].view(3,-1), 1]}
        
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations, 3, normalize_fact_novel)
        BP_act_out = BPTokens_retrieveByToken(bpsize, bpPortion, BPOut, Tokenbindings, BP_activations, 3, normalize_fact_novel)
        BP_l1_H = BP_act_out['l1']
        BP_object_H = BP_act_out['object']
        BP_color_H = BP_act_out['color']

        obj_recon_H = vae.decoder_retinal_object(BP_object_H, BP_color_H, thetas, 0).sum(dim=0, keepdim=True)
        holistic_H = vae.decoder_skip_cropped(0, 0, 0, BP_l1_H)
        holistic_H = F.interpolate(holistic_H, size=(64, 64), mode='bilinear', align_corners=False)
        holistic_H = Ft.gaussian_blur(holistic_H, kernel_size=[79, 79], sigma=[5.5, 5.5]) #F.avg_pool2d(holistic_H, kernel_size=15, stride=1, padding=15 // 2)
        hybrid = composite_scene(holistic_H, obj_recon_H[0], torch.zeros_like(obj_recon_H[0]), device)
        hybrid_col.append(hybrid.view(bs, 3, 64, 64))

        # hybrid holistic bg + object one hots:
        BP_activations_oneHot_H = {'object': [object_oneHot.view(3, -1), 1],
                                'color': [color_oneHot.view(3, -1), 1],
                                'l1': [holistict_activations['skip'].view(3,-1), 1]}       
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_oneHot_H, 3, normalize_fact_novel)
        BP_act_out = BPTokens_retrieveByToken(bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_oneHot_H, 3, normalize_fact_novel)
        BP_obj_out_label = BP_act_out['object']
        BP_color_out_label = BP_act_out['color']
        BP_l1_H = BP_act_out['l1']

        # remove noise from BP output by converting back to 1-hot
        BP_obj_indices = torch.argmax(BP_obj_out_label, dim=-1)
        BP_color_indices = torch.argmax(BP_color_out_label, dim=-1)
        BP_obj_indices = find_closest_index(BP_obj_indices, [0, 2, 8, 10, 11])
        BP_obj_out_label = F.one_hot(BP_obj_indices, num_classes=BP_obj_out_label.size(-1)).to(device).float()
        BP_color_out_label = F.one_hot(BP_color_indices, num_classes=BP_color_out_label.size(-1)).to(device).float()

        obj_from_BP_label_H = object_label(BP_obj_out_label, 1)
        color_from_BP_label_H = color_label(BP_color_out_label, 1)

        obj_recon_H = vae.decoder_retinal_object(obj_from_BP_label_H, color_from_BP_label_H, thetas, 0).sum(dim=0, keepdim=True)
        holistic_H = vae.decoder_skip_cropped(0, 0, 0, BP_l1_H)
        holistic_H = F.interpolate(holistic_H, size=(64, 64), mode='bilinear', align_corners=False)
        holistic_H = Ft.gaussian_blur(holistic_H, kernel_size=[79, 79], sigma=[5.5, 5.5])
        hybrid_H = composite_scene(holistic_H, obj_recon_H[0], torch.zeros_like(obj_recon_H[0]), device)
        hybrid_1hot_col.append(hybrid_H.view(bs, 3, 64, 64))

        # hybrid holistic bg + 2 object one hots + 1 obj latents:
        BP_activations_oneHot_H = {'object': [objs[0].view(1, -1), 1],
                                'color': [colors[0].view(1, -1), 1],
                                'object_1hot': [object_oneHot[1:].view(2, -1), 1],
                                'color_1hot': [color_oneHot[1:].view(2, -1), 1],
                                'l1': [holistict_activations['skip'].view(1,-1), 1],
                                'act_bitmask': [[1, 1, 0, 0, 0], [0, 0, 1, 1,0], [0, 0, 1, 1,0], [0,0,0,0,1]],
                                'act_name_map': ['object', 'color', 'object_1hot', 'color_1hot', 'l1']}       
        BPOut, Tokenbindings = BPTokens_storage_bitmask(bpsize, bpPortion, BP_activations_oneHot_H, 4, normalize_fact_novel)
        #print('here')
        BP_act_out = BPTokens_retrieveByToken_bitmask(bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_oneHot_H, 4, normalize_fact_novel)
        BP_obj_out_hybrid = BP_act_out['object']
        BP_color_out_hybrid = BP_act_out['color']
        BP_obj_out_label = BP_act_out['object_1hot']
        BP_color_out_label = BP_act_out['color_1hot']
        BP_l1_H = BP_act_out['l1']
        #print(BP_l1_H.shape)

        # remove noise from BP output by converting back to 1-hot
        BP_obj_indices = torch.argmax(BP_obj_out_label, dim=-1)
        BP_color_indices = torch.argmax(BP_color_out_label, dim=-1)
        BP_obj_indices = find_closest_index(BP_obj_indices, [0, 2, 8, 10, 11])
        BP_obj_out_label = F.one_hot(BP_obj_indices, num_classes=BP_obj_out_label.size(-1)).to(device).float()
        BP_color_out_label = F.one_hot(BP_color_indices, num_classes=BP_color_out_label.size(-1)).to(device).float()

        obj_from_BP_label_H = object_label(BP_obj_out_label, 1)
        color_from_BP_label_H = color_label(BP_color_out_label, 1)

        hybrid_objs = torch.cat([BP_obj_out_hybrid, obj_from_BP_label_H], 0)
        hybrid_colors = torch.cat([BP_color_out_hybrid, color_from_BP_label_H], 0)

        obj_recon_H = vae.decoder_retinal_object(hybrid_objs, hybrid_colors, thetas, 0).sum(dim=0, keepdim=True)
        holistic_H = vae.decoder_skip_cropped(0, 0, 0, BP_l1_H)
        holistic_H = F.interpolate(holistic_H.view(1,3,28,28), size=(64, 64), mode='bilinear', align_corners=False)
        holistic_H = Ft.gaussian_blur(holistic_H, kernel_size=[79, 79], sigma=[5.5, 5.5])
        hybrid_H = composite_scene(holistic_H, obj_recon_H[0], torch.zeros_like(obj_recon_H[0]), device)
        hybrid_bitmask_col.append(hybrid_H.view(bs, 3, 64, 64))

        # reconstruct
        obj_recon_no_BP = vae.decoder_retinal_object(objs, colors, thetas, 0).sum(dim=0, keepdim=True)
        obj_recon_BP = vae.decoder_retinal_object(BP_obj_out, BP_color_out, thetas, 0).sum(dim=0, keepdim=True)
        obj_recon_BP_label = vae.decoder_retinal_object(obj_from_BP_label, color_from_BP_label, thetas, 0).sum(dim=0, keepdim=True)
        obj_recon_label = vae.decoder_retinal_object(obj_from_label, color_from_label, thetas, 0).sum(dim=0, keepdim=True)
        holistic_BP = vae.decoder_skip_cropped(0, 0, 0, BP_l1_out)
        holistic_no_BP = vae.decoder_skip_cropped(0, 0, 0, holistict_activations['skip'])
        holistic_BP = F.interpolate(holistic_BP, size=(64, 64), mode='bilinear', align_corners=False)
        holistic_no_BP = F.interpolate(holistic_no_BP, size=(64, 64), mode='bilinear', align_corners=False)

        comb_img_col.append(comb_img.view(bs, 3, 64, 64))
        obj_recon_no_BP_col.append(obj_recon_no_BP.view(bs, 3, 64, 64))
        obj_recon_BP_col.append(obj_recon_BP.view(bs, 3, 64, 64))
        obj_recon_label_col.append(obj_recon_label.view(bs, 3, 64, 64))
        obj_recon_BP_label_col.append(obj_recon_BP_label.view(bs, 3, 64, 64))
        holistic_no_BP_col.append(holistic_no_BP.view(bs, 3, 64, 64))
        holistic_BP_col.append(holistic_BP.view(bs, 3, 64, 64))

    if save_img:
        save_image(
            torch.cat([torch.cat(comb_img_col, 0), torch.cat(obj_recon_no_BP_col, 0),
            torch.cat(obj_recon_BP_col, 0), torch.cat(obj_recon_label_col, 0),
            torch.cat(obj_recon_BP_label_col, 0), torch.cat(holistic_no_BP_col, 0),
            torch.cat(holistic_BP_col, 0), torch.cat(hybrid_col, 0), torch.cat(hybrid_1hot_col, 0), torch.cat(hybrid_bitmask_col, 0)], 0),
            f'{folder_path}figure_obj_scene_{scene_idx}.png', pad_value=0.6,
            nrow=n, normalize=False)

    if return_loss:
        losses = {
            'holistic_no_BP': F.mse_loss(torch.cat(comb_img_col, 0), torch.cat(holistic_no_BP_col, 0)).item(),
            'holistic_BP': F.mse_loss(torch.cat(comb_img_col, 0), torch.cat(holistic_BP_col, 0)).item(),
            'latent_obj_holistic_bg': F.mse_loss(torch.cat(comb_img_col, 0), torch.cat(hybrid_col, 0)).item(),
            '1hot_obj_holistic_bg': F.mse_loss(torch.cat(comb_img_col, 0), torch.cat(hybrid_1hot_col, 0)).item(),
            'hybrid_obj': F.mse_loss(torch.cat(comb_img_col, 0), torch.cat(hybrid_bitmask_col, 0)).item()}
        return losses

@torch.no_grad()
def fig_obj_scene_recon(vae: VAE_CNN, object_label, color_label, object_classifier, color_classifier, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    vae.eval()
    bpsize = 5000#00         #size of the binding pool
    token_overlap =0.3
    n = 7
    bpPortion = int(token_overlap *bpsize) # number binding pool neurons used for each item

    bs = 1
    device = next(vae.parameters()).device
    object_label.to(device)
    # holistic rep for background, lowpass filter average, latent representation for objects, reconstruct and layer
    # MSE for each reconstruction row over 1000 trials.
    quickdraw_target_set = [0, 2, 8, 10, 11]
    obj_1_transforms = {'retina': True, 'colorize': True, 'scale': False, 'target_set': quickdraw_target_set,
                        'location_targets': {(-1, -1): list(range(0, s_classes + 1))}, 'colorize_background':'split'}
    obj_1_loader = Dataset('quickdraw', obj_1_transforms).get_loader(bs)

    obj_2_transforms = {'retina': True, 'colorize': True, 'scale': False, 'target_set': quickdraw_target_set,
                        'location_targets': {(-1, 1): list(range(0, s_classes + 1))}}
    obj_2_loader = Dataset('quickdraw', obj_2_transforms).get_loader(bs)

    obj_3_transforms = {'retina': True, 'colorize': True, 'scale': False, 'target_set': quickdraw_target_set,
                        'location_targets': {(1, 1): list(range(0, s_classes + 1))}}
    obj_3_loader = Dataset('quickdraw', obj_3_transforms).get_loader(bs)

    dataloaders = (obj_1_loader, obj_2_loader, obj_3_loader, bs)

    losses_junk = obj_scene_helper(vae, dataloaders, n, save_img=True, return_loss=True, bpsize=bpsize, bpPortion=bpPortion, object_label=object_label, color_label=color_label, object_classifier=object_classifier, color_classifier=color_classifier, folder_path=folder_path)
    loss_trials = 200
    losses_dict = {}
    for bpsize in [10000, 7000, 5000, 4000, 3000, 1000, 500]:
        losses_dict[bpsize] = obj_scene_helper(vae, dataloaders, loss_trials, save_img=False, return_loss=True, bpsize=bpsize, bpPortion=bpPortion, object_label=object_label, color_label=color_label, object_classifier=object_classifier, color_classifier=color_classifier, folder_path=folder_path)

    # TODO: new hybrid strat: present an atypical obj on bottom, store top 2 as labels, bottom as latents, w/ hol bg
    for bps in losses_dict:
        losses = losses_dict[bps]
        names = list(losses.keys())
        values = list(losses.values())
        # ingredient vector mark token as shape, color, etc

        fig, ax = plt.subplots(figsize=(10, 6))
        bars = ax.bar(names, values, color='steelblue')

        ax.set_ylabel('MSE Loss')
        ax.set_title(f'MSE vs Reconstruction Method {loss_trials} Trials, BP size: {bps}')
        ax.set_xticklabels(names, rotation=45, ha='right')
        ax.grid(axis='y', alpha=0.3)

        for bar, val in zip(bars, values):
            ax.text(bar.get_x() + bar.get_width() / 2, bar.get_height(),
                    f'{val:.4f}', ha='center', va='bottom', fontsize=9)

        plt.tight_layout()
        plt.savefig(f'{folder_path}reconstruction_error_{bps}.png')

def visual_synthesis_helper(vae: VAE_CNN, num1, num2, theta, bs, shape_label: VAEshapelabels, s_classes, object_classifier, folder_path: str, save_images: bool = False):
    letter1 = emnist_labels[num1]
    letter2 = emnist_labels[num2]
    device = next(vae.parameters()).device
    shape_label.to(device)
    num_labels = F.one_hot(torch.tensor([num1, num2]).to(device), num_classes=s_classes).float().to(device) # shape
    z_shape = shape_label(num_labels, 8)
    recon_crop = vae.decoder_shape(z_shape)    
    recon = vae.decoder_retinal(z_shape, 0, theta, 'shape')

    img1 = recon[0]
    img2 = recon[1]
    comb_img = torch.clamp(img1 + img2, 0, 0.5) * 1.3
    comb_img = comb_img.view(1,3,64,64)

    activations = vae.activations(comb_img, True, None, 'object')

    pred_ss = object_classifier.predict(activations['object'].cpu())
    out_pred = pred_ss[0]    

    if save_images:
        recon_shape = vae.decoder_object(activations['object'], 0, 0)
        recon_shape_retinal = vae.decoder_retinal_object(activations['object'], activations['color'], activations['theta'], 0)
        save_image(comb_img, f'{folder_path}{letter1}_{letter2}_sim.png')
        save_image(recon_shape, f'{folder_path}{letter1}_{letter2}_sim_recon.png')
        save_image(recon_shape_retinal, f'{folder_path}{letter1}_{letter2}_sim_recon_retinal.png')
        save_image(recon_crop, f'{folder_path}{letter1}_{letter2}_crop_recon.png')
        save_image(img1, f'{folder_path}{letter1}.png')
        save_image(img2, f'{folder_path}{letter2}.png')
        save_image(activations['stn_out'], f'{folder_path}stn_out.png')

    return out_pred

@torch.no_grad()
def fig_visual_synthesis_umbrella(vae: VAE_CNN, shape_label, s_classes, object_classifier, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    #TODO: rotated V in an O to form clock, J under rotated D to form an umbrella
    if not os.path.exists(folder_path):
        os.mkdir(folder_path)
    vae.eval()
    bs = 2
    num1 = 13 # D
    num2 = 19 # J

    location = torch.tensor([[0.35, 0.1], [0.0, 0.4]]).view(bs,2).to(device)
    scale = torch.tensor([[4.4], [1.0]]).view(bs,1).to(device)
    rotation = torch.tensor([[-3.5], [0.3]]).view(bs,1).to(device)
    theta = torch.cat([scale, location, rotation], 1)

    preds = defaultdict(int)
    trial_count = 500
    for i in range(trial_count):
        out_pred = visual_synthesis_helper(vae, num1, num2, theta, bs, shape_label, s_classes, object_classifier, folder_path, save_images= i==0)
        preds[out_pred] += 1

    accuracy = preds[object_names.index('umbrella')] / trial_count
    with open(f"{folder_path}results.txt", "w") as f:
        for cls in preds:
            f.write(f'{object_names[cls]}: {preds[cls]} out of {trial_count}\n')
        f.write(f'Accuracy: {accuracy:.4f}')
    
@torch.no_grad()
def fig_visual_synthesis_clock(vae: VAE_CNN, shape_label, s_classes, object_classifier, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    #TODO: rotated V in an O to form clock, J under rotated D to form an umbrella
    if not os.path.exists(folder_path):
        os.mkdir(folder_path)
    vae.eval()
    bs = 2
    num1 = 0 #24
    num2 = 31

    location = torch.tensor([[-0.2, 0.0], [0.05, 0.0]]).view(bs,2).to(device)
    scale = torch.tensor([[3.4], [0.5]]).view(bs,1).to(device)
    rotation = torch.tensor([[-0.4], [0.4]]).view(bs,1).to(device)
    theta = torch.cat([scale, location, rotation], 1)

    preds = defaultdict(int)
    trial_count = 500
    for i in range(trial_count):
        out_pred = visual_synthesis_helper(vae, num1, num2, theta, bs, shape_label, s_classes, object_classifier, folder_path, save_images= i==0)
        preds[out_pred] += 1

    accuracy = preds[object_names.index('clock')] / trial_count
    with open(f"{folder_path}results.txt", "w") as f:
        for cls in preds:
            f.write(f'{object_names[cls]}: {preds[cls]} out of {trial_count}\n')
        f.write(f'Accuracy: {accuracy:.4f}')

@torch.no_grad()
def fig_visual_synthesis_boat(vae: VAE_CNN, shape_label, s_classes, object_classifier, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    #TODO: rotated V in an O to form clock, J under rotated D to form an umbrella
    if not os.path.exists(folder_path):
        os.mkdir(folder_path)
    
    vae.eval()
    bs = 2
    num1 = 13
    num2 = 25

    location = torch.tensor([[0.0, 0.0], [0.05, -0.3]]).view(bs,2).to(device)
    scale = torch.tensor([[3.1], [0.5]]).view(bs,1).to(device)
    rotation = torch.tensor([[4.0], [0.0]]).view(bs,1).to(device)
    theta = torch.cat([scale, location, rotation], 1)

    preds = defaultdict(int)
    trial_count = 500
    for i in range(trial_count):
        out_pred = visual_synthesis_helper(vae, num1, num2, theta, bs, shape_label, s_classes, object_classifier, folder_path, save_images= i==0)
        preds[out_pred] += 1

    accuracy = preds[object_names.index('sailboat')] / trial_count
    with open(f"{folder_path}results.txt", "w") as f:
        for cls in preds:
            f.write(f'{object_names[cls]}: {preds[cls]} out of {trial_count}\n')
        f.write(f'Accuracy: {accuracy:.4f}')

def build_gen_grid(joint_recons, shape_recons, color_recons, n):
    grid_rows = []
    empty_block = torch.zeros_like(joint_recons[0])

    for i in range(n + 1):
        row_blocks = []
        for j in range(n + 1):
            if i == 0 and j > 0:
                block = shape_recons[j - 1]
            elif j == 0 and i > 0:
                block = color_recons[i - 1]
            elif i == j:
                block = joint_recons[i]
            else:
                block = empty_block

            if block.dim() == 4 and block.shape[0] == 1:
                block = block.squeeze(0)

            row_blocks.append(block)

        # concat horizontally
        row = torch.cat(row_blocks, dim=2)
        grid_rows.append(row)

    # concat vertically
    return torch.cat(grid_rows, dim=1)

def rgb_to_lab_norm(imgs_rgb: torch.Tensor,
                    l_min: float = 50,
                    l_max: float = 70) -> torch.Tensor:
    """
    Convert (B, 3, H, W) RGB in [0,1] to normalized Lab in [0,1].
    L* normalized using the same [l_min, l_max] range as the dataloader.
    a*, b* normalized over [-128, 127] (full Lab gamut).
    returns: (B, 3, H, W)
    """
    linear = torch.where(
        imgs_rgb <= 0.04045,
        imgs_rgb / 12.92,
        ((imgs_rgb + 0.055) / 1.055) ** 2.4,
    )

    X = (0.4124564 * linear[:, 0] +
         0.3575761 * linear[:, 1] +
         0.1804375 * linear[:, 2]).unsqueeze(1)
    Y = (0.2126729 * linear[:, 0] +
         0.7151522 * linear[:, 1] +
         0.0721750 * linear[:, 2]).unsqueeze(1)
    Z = (0.0193339 * linear[:, 0] +
         0.1191920 * linear[:, 1] +
         0.9503041 * linear[:, 2]).unsqueeze(1)

    X = X / 0.95047
    Z = Z / 1.08883

    delta = 6.0 / 29.0
    def f(t):
        return torch.where(t > delta ** 3,
                           t.pow(1.0 / 3.0),
                           t / (3 * delta ** 2) + 4.0 / 29.0)

    fx, fy, fz = f(X), f(Y), f(Z)

    L     = 116.0 * fy - 16.0          # [0, 100]
    a_star = 500.0 * (fx - fy)         # [-128, 127] approx
    b_star = 200.0 * (fy - fz)

    # Normalize L* using dataloader range — same mapping as Colorize_specific
    L_norm = ((L - l_min) / (l_max - l_min)).clamp(0.0, 1.0)
    a_norm = ((a_star + 128.0) / 255.0).clamp(0.0, 1.0)
    b_norm = ((b_star + 128.0) / 255.0).clamp(0.0, 1.0)

    return torch.cat([L_norm, a_norm, b_norm], dim=1)   # (B, 3, H, W)

def visualize_color_objective(imgs, imgsize,
                               l_min: float = 50,
                               l_max: float = 70):
    """
    imgs : (B, 3, H, W) in [0,1]
    returns : (B, 3, H, W) in [0,1] — flat-color patch using mean Lab
    """
    B = imgs.shape[0]
    imgs = imgs.view(B, 3, imgsize, imgsize)

    brightness = imgs.max(dim=1, keepdim=True).values
    mask = (brightness > 0.15).float()
    fg_count = mask.sum(dim=[2, 3], keepdim=True).clamp(min=1)

    lab = rgb_to_lab_norm(imgs, l_min, l_max)                          # (B, 3, H, W)
    mean_lab = (lab * mask).sum(dim=[2, 3], keepdim=True) / fg_count   # (B, 3, 1, 1)
    flat_lab = mean_lab.expand(B, 3, imgsize, imgsize)                 # (B, 3, H, W)

    # Denormalize back to raw Lab for conversion
    L      = flat_lab[:, 0:1] * (l_max - l_min) + l_min   # [l_min, l_max]
    a_star = flat_lab[:, 1:2] * 255.0 - 128.0
    b_star = flat_lab[:, 2:3] * 255.0 - 128.0

    # Lab -> XYZ
    fy = (L + 16.0) / 116.0
    fx = a_star / 500.0 + fy
    fz = fy - b_star / 200.0

    delta = 6.0 / 29.0
    def f_inv(t):
        return torch.where(t > delta,
                           t ** 3,
                           3 * delta ** 2 * (t - 4.0 / 29.0))

    X = f_inv(fx) * 0.95047
    Y = f_inv(fy)
    Z = f_inv(fz) * 1.08883

    M_inv = torch.tensor([
        [ 3.2404542, -1.5371385, -0.4985314],
        [-0.9692660,  1.8760108,  0.0415560],
        [ 0.0556434, -0.2040259,  1.0572252],
    ], dtype=imgs.dtype, device=imgs.device)

    xyz = torch.cat([X, Y, Z], dim=1).view(B, 3, -1)
    rgb_linear = torch.einsum('cd,bdp->bcp', M_inv, xyz).view(B, 3, imgsize, imgsize).clamp(0, 1)

    rgb = torch.where(
        rgb_linear <= 0.0031308,
        rgb_linear * 12.92,
        1.055 * rgb_linear.pow(1.0 / 3.0) - 0.055,
    )
    return rgb.clamp(0.0, 1.0)

@torch.no_grad()
def functionality_test(vae: VAE_CNN, shape_label, s_classes, color_label, c_classes, folder_path: str):
    vae.eval()
    #vae.skip_bn.train()
    device = next(vae.parameters()).device
    emnist_targetset = [2, 3, 12, 15, 25]
    mnist_transforms = {'retina':True, 'colorize':True, 'rotate':False, 'scale':True} #, 'target_set':emnist_targetset}
    emnist_loader= Dataset('square', mnist_transforms).get_loader(50)
    
    dataiter_emnist = iter(emnist_loader)
    data, labels = next(dataiter_emnist)
    data = data[1].cuda()
    sample_size = 25
    sample = data[:sample_size].to(device)   #the actual image


    # color label testing
    x = sample
    target = visualize_color_objective(x, imgsize, 50, 70)
    # END COLOR LABELS
    name = ''
    vae.dropout.p = 0
    #sample = data[:sample_size].to(device)   #the actual image
    with torch.no_grad():
        if 'quickdraw' in name:
            recon, _, _, _, _, _, _ = vae(sample, 'cropped_object', ['object', 'color'])
            shape, _, _, _, _, _, _ = vae(sample, 'object', ['object'])
        else:
            recon, _, _, _, _, _, _ = vae(sample, 'cropped', ['shape', 'color'])
            shape, _, _, _, _, _, _ = vae(sample, 'shape', ['shape'])
        color, _, _, _, _, _, _ = vae(sample, 'color', ['color'])
        skip, _, _, _, _, _, _ = vae(sample, 'skip_cropped', ['skip'])

    vae.dropout.p = 0.1 
     
    output_img = torch.cat([sample.view(sample_size, 3, imgsize, imgsize)[:25], recon.view(sample_size, 3, imgsize, imgsize)[:25], skip.view(sample_size, 3, imgsize, imgsize)[:25],
                       shape.view(sample_size, 3, imgsize, imgsize)[:25], color.view(sample_size, 3, imgsize, imgsize)[:25], target.view(sample_size, 3, imgsize, imgsize)[:25]], 0)
     
    rows = 6;    
    #print(sample_size)
    #this next bit collapses the long image into a stack of rows so that the text can be added
    #convert the sample_size*rows x 3 x 28 x 28 tensor into a  stack that is now 3 x rows*28 x sample_size*28
    output_img2 = output_img.view(rows,sample_size,3,28,28)
    output_img2 = output_img2.permute(0,2,3,1,4).contiguous().view(rows,3,28,sample_size*28)
    output_img2 = output_img2.permute(1,0,2,3).contiguous().view(3,rows*28,sample_size*28)

    channels, height, width = output_img2.shape
    header_height = 20            
    # Create new tensor with extra height for text
    new_height = height + header_height
    new_tensor = torch.ones(channels, new_height, width) * 0.8  # Light gray background
    new_tensor[:, header_height:, :] = output_img2
    text_tensor = text_to_tensor("Image / both maps recon / skip recon / shape recon/color recon / color objective ",header_height,width)
    new_tensor[:, :header_height, :] = text_tensor
    save_image(new_tensor,f'{folder_path}cropped_sample_{name}.png',
            nrow=1, normalize=False)



@torch.no_grad()
def fig_generative_noise(vae: VAE_CNN, shape_label, s_classes, color_label, c_classes, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    vae.eval()

    if load_data is False:
        print("generative noise plot")
        bs = 2
        x, y= 5, 5
        num1 = 35
        num2 = 25
        device = next(vae.parameters()).device
        shape_label.to(device)
        num_labels = F.one_hot(torch.tensor([num1, num2]).to(device), num_classes=s_classes).float().to(device) # shape
        col_labels = F.one_hot(torch.tensor([1, 0]).to(device), num_classes=c_classes).float().to(device) # color
        print(num_labels.size())
        z_shapes = shape_label(num_labels, 1)
        z_colors = color_label(col_labels, 1)

        # shape / color noising x: shape, y: color
        recon_crop = vae.decoder_cropped(z_shapes[0], z_colors[0])
        shape_color_base = recon_crop[0]

        shape_recons = []
        color_recons = []
        joint_recons = [shape_color_base]

        z_shape = z_shapes[0].clone()
        z_color = z_colors[0].clone()
        n = 10
        for i in range(0,n):
            z_shape = z_shape + 0.999 * ((1)/n) * (z_shapes[1] - z_shapes[0]) + (0.0 * torch.randn_like(z_shape))
            z_color = z_color + 0.99 * ((1)/n) * (z_colors[1] - z_colors[0]) + (0.2 * torch.randn_like(z_color))
            recon_shape_m = vae.decoder_cropped(z_shape, z_colors[0])
            recon_color_m = vae.decoder_cropped(z_shapes[0], z_color)
            recon_crop_m = vae.decoder_cropped(z_shape, z_color)

            shape_recons += [recon_shape_m]
            color_recons += [recon_color_m]
            joint_recons += [recon_crop_m]

        recon_grid = build_gen_grid(joint_recons, shape_recons, color_recons, n)
        data_to_pickle = {
            "recon_grid": recon_grid,
        }

        joblib.dump(data_to_pickle, pkl_path)

    else:
        if not os.path.exists(pkl_path):
            raise Exception(f"No data exists for plot: {folder_path}{log_function_name()}")
        
        # load plotting data
        loaded_data = joblib.load(pkl_path)
        recon_grid = loaded_data["recon_grid"]
    
    save_image(recon_grid, f'{folder_path}sample.png', pad_value=0.6)

def binding_trial(trial_name: str, dataset, vae: VAE_CNN, color_classifier, numimg, folder_path: str):
    
    token_overlap = 0.3
    bpPortion = int(token_overlap *bpsize)

    test_loader = cycle(dataset.get_loader(numimg))
    dataiter = iter(test_loader)
    total_trials = 100
    out_predictions = 0
    token_predictions = 0
    
    green = Colorize_specific(1)
    red = Colorize_specific(0)

    for _ in range(total_trials):
        imgs, targets = next(dataiter)

        imgs = imgs.cuda()

        # greyscale
        weights = torch.tensor([0.2989, 0.5870, 0.1140], device=imgs.device).view(1, 3, 1, 1)
        grey = (imgs * weights).sum(dim=1, keepdim=True)  # [B, 1, H, W]
        grey_imgs = grey.repeat(1, 3, 1, 1)

        #push the images through the encoder
        activations = vae.activations(imgs.view(-1,3,imgsize, imgsize), False)
        shape_act = activations['shape']
        color_act = activations['color']

        grey_activations = vae.activations(grey_imgs.view(-1,3,imgsize, imgsize), False)
        grey_shape_act = grey_activations['shape']
        
        BP_activations_sc = {'shape': [shape_act.view(numimg,-1), 1], 'color': [color_act.view(numimg,-1), 1]}
        
        #now store digits
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_sc, numimg, normalize_fact_novel)
        
        BPOut_cued = BPOut.clone()
        # cue by greyscale shape activation of first image
        tokenactivation = torch.zeros(numimg)
        notLink_all = Tokenbindings[0]
        shape_fw = Tokenbindings[1]
        BP_reactivate = torch.mm(grey_shape_act[0].view(1, -1),shape_fw)
        BP_reactivate = BP_reactivate  * BPOut

        for tokens in range(numimg):  # for each token
            BP_reactivate_tok = BP_reactivate.clone()
            BP_reactivate_tok[0,notLink_all[tokens, :]] = 0  # set the BPs to zero for this token retrieval
            # for this demonstration we're assuming that all BP-> token weights are equal to one, so we can just sum the
            # remaining binding pool neurons to get the token activation
            tokenactivation[tokens] = BP_reactivate_tok.sum()

        max, maxtoken =torch.max(tokenactivation,0) #which token has the most activation
        BPOut_cued[0, notLink_all[maxtoken, :]] = 0

        BP_act_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_sc, numimg, normalize_fact_novel)
        BP_act_out_cued = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut_cued, Tokenbindings, BP_activations_sc, numimg, normalize_fact_novel)
        
        #cued_prediction = shape_classifier.predict(BP_act_out_cued['shape'][0].view(1,-1).cpu())
        #print(targets[0], cued_prediction)
        cued_color_prediction = color_classifier.predict(BP_act_out_cued['color'][maxtoken].view(1,-1).cpu())
        #print(cued_color_prediction, targets[1][0])
        if cued_color_prediction == targets[1][0].item():
            out_predictions += 1
        if maxtoken == 0:
            token_predictions += 1

    print(f"Correct token: {token_predictions/total_trials} of {total_trials} trials")
    print(f"Correct color: {out_predictions/total_trials} of {total_trials} trials")
    with open(f"{folder_path}{trial_name}results.txt", "w") as f:
        f.write(f"Correct token: {token_predictions/total_trials} of {total_trials} trials\n")
        f.write(f"Correct color: {out_predictions/total_trials} of {total_trials} trials\n")

    
    shape_out_BP, color_out_BP = BP_act_out['shape'], BP_act_out['color']
    shape_out_BP_cued, color_out_BP_cued = BP_act_out_cued['shape'], BP_act_out_cued['color']
    BP_cropped_recon = vae.decoder_cropped(shape_out_BP, color_out_BP)
    BP_cropped_recon_cued = vae.decoder_cropped(shape_out_BP_cued, color_out_BP_cued)
    empty = torch.zeros(1,3,imgsize,imgsize).cuda()
    grey_cue = torch.cat([grey_imgs[0].view(1,3,imgsize,imgsize), empty]).view(numimg, 3, imgsize, imgsize)
    BP_cropped_recon_cued = torch.cat([BP_cropped_recon_cued[0].view(1,3,imgsize,imgsize), empty]).view(numimg, 3, imgsize, imgsize)
    sample = imgs[0: numimg].view(numimg, 3, imgsize, imgsize)

    #save an image showing:  original images, reconstructions directly from L1,  from L1 BP, from L1 BP through bottleneck, from maps BP
    fig_data_list = [sample, BP_cropped_recon, grey_cue, BP_cropped_recon_cued]
    
    # save params used in this simulation run
    with open(f"{folder_path}params.txt", "w") as f:
        f.write(f"bpsize: {bpsize}\n")
        f.write(f"token_overlap: {token_overlap}\n")
        f.write(f"bpPortion: {bpPortion}\n")
    
    return fig_data_list

@torch.no_grad()
def fig_binding_addressability(vae: VAE_CNN, color_classifier, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    vae.eval()
    if load_data is False:
        print("addressability figure")
        # store 2 digits, generate activations of greyscaled rep of 1 of the digits, retrieve from BP using that as a cue
        
        numimg = 2

        dataset = Dataset('emnist',{'retina':False, 'colorize':True, 'rotate':False, 'scale':True}, train=False)
        dataset_2 = Dataset('emnist',{'retina':False, 'colorize':True, 'rotate':False, 'scale':True, 'target_set':[10]}, train=False)
        # these functions  actually do the work
        fig_data_list_r = binding_trial('emnist_rand', dataset, vae, color_classifier, numimg, folder_path)
        fig_data_list_2 = binding_trial('emnist_2', dataset_2, vae, color_classifier, numimg, folder_path)
    
        data_to_pickle = {
            "fig_data_list_r": fig_data_list_r,
            "fig_data_list_2": fig_data_list_2
        }

        joblib.dump(data_to_pickle, pkl_path)

    else:
        if not os.path.exists(pkl_path):
            raise Exception(f"No data exists for plot: {folder_path}{log_function_name()}")
        
        # load plotting data
        loaded_data = joblib.load(pkl_path)
        fig_data_list_r = loaded_data["fig_data_list_r"]
        fig_data_list_2 = loaded_data["fig_data_list_2"]

    save_image(torch.cat(fig_data_list_r, 0), f'{folder_path}mnist_rand-addressability.png',
                nrow=numimg, normalize=False, pad_value=0.6)

    save_image(torch.cat(fig_data_list_2, 0), f'{folder_path}mnist_2-addressability.png',
            nrow=numimg, normalize=False, pad_value=0.6)

def sample_points(n, m, k=5, min_dist=5):
    points = []

    def far_enough(p, q):
        dist = ((p[0] - q[0]) ** 2 + (p[1] - q[1]) ** 2) ** 0.5
        return dist >= min_dist   # Euclidean distance

    attempts = 0
    max_attempts = 10_000

    while len(points) < k and attempts < max_attempts:
        candidate = (random.randint(0, n-1), random.randint(0, m-1))
        if all(far_enough(candidate, p) for p in points):
            points.append(candidate)
        attempts += 1

    if len(points) < k:
        raise RuntimeError("Failed to place points with required spacing.")

    return points

def feature_swap_trial(dataset, vae: VAE_CNN, numimg: int, imgsize: int):
    test_loader = cycle(dataset.get_loader(numimg))
    dataiter = iter(test_loader)
    
    errors_1 = []
    errors_2 = []
    correct_token_err = []
    correct_token_chosen_err = []
    token_swap = 0
    swap_count = 0
    trial_count = 10
    for _ in range(trial_count):
        crop_imgs = next(dataiter)[0].cuda()

        imgs = torch.zeros(numimg,3,64,64).cuda()
        locations = sample_points(64 - imgsize, 64 - imgsize, k=numimg, min_dist=5)
        colors = []
        for i in range(numimg):
            x, y = locations[i]
            imgs[i,:,x:x+imgsize,y:y+imgsize] = crop_imgs[i]
            color = 1 #random.randint(0,9)
            colors.append(color)
            colorizer = Colorize_specific(color)
            frame = convert_tensor(colorizer(convert_image(imgs[i].cpu())))
            imgs[i] = frame.cuda()
        
        excluded_colors = colors.copy()
        crop_imgs_ex = next(dataiter)[0].cuda()
        imgs_ex = torch.zeros(numimg,3,64,64).cuda()
        for i in range(numimg):
            x, y = locations[i]
            imgs_ex[i,:,x:x+imgsize,y:y+imgsize] = crop_imgs_ex[i]
            color = random.randint(0,9)
            colorizer = Colorize_specific(color)
            frame = convert_tensor(colorizer(convert_image(imgs_ex[i].cpu())))
            imgs_ex[i] = frame.cuda()

        #push the images through the encoder
        activations = vae.activations(imgs.view(-1,3,64, 64), True)
        shape_act = activations['shape']
        color_act = activations['color']
        location_act = activations['location']

        cue_activations = vae.activations(imgs[0].view(-1,3,64, 64), True)
        #cue_shape_act = cue_activations['shape']
        cue_location_act = cue_activations['location']

        excluded_activations = vae.activations(imgs_ex.view(-1,3,64, 64), True)
        #excluded_shape_act = excluded_activations['shape']
        excluded_color_act = excluded_activations['color']
        
        BP_activations_sc = {'shape': [shape_act.view(numimg,-1), 1],
                             'color': [color_act.view(numimg,-1), 1],
                             'location': [location_act.view(numimg,-1), 1]}
        
        #now store digits
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_sc, numimg, normalize_fact_novel)
        
        BPOut_cued = BPOut.clone()
        # cue by greyscale shape activation of first image
        tokenactivation = torch.zeros(numimg)
        notLink_all = Tokenbindings[0]
        location_fw = Tokenbindings[3]
        BP_reactivate = torch.mm(cue_location_act.view(1, -1),location_fw)
        BP_reactivate = BP_reactivate  * BPOut

        for tokens in range(numimg):  # for each token
            BP_reactivate_tok = BP_reactivate.clone()
            BP_reactivate_tok[0,notLink_all[tokens, :]] = 0
            tokenactivation[tokens] = BP_reactivate_tok.sum()

        max, maxtoken =torch.max(tokenactivation,0) #which token has the most activation
        BPOut_cued[0, notLink_all[maxtoken, :]] = 0

        BP_act_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_sc, numimg, normalize_fact_novel)
        BP_act_out_cued = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut_cued, Tokenbindings, BP_activations_sc, numimg, normalize_fact_novel)
        
        shape_out_BP, color_out_BP = BP_act_out['shape'], BP_act_out['color']
        shape_out_BP_cued, color_out_BP_cued = BP_act_out_cued['shape'], BP_act_out_cued['color']
        
        print(color_out_BP_cued.size())
        errors = []
        for i in range(numimg):
            errors += [torch.norm(color_act[i]-color_out_BP_cued[0]).item()]
        
        correct_token_err += [errors[0]]
        
        if maxtoken == 0:
            correct_token_chosen_err += [torch.norm(color_act[0]-color_out_BP_cued[0]).item()]
        
        if maxtoken != 0:
            token_swap += 1

        elif errors[0] != min(errors):
            swap_count += 1

        excluded_errors = []
        for i in range(numimg):
            excluded_errors += [torch.norm(excluded_color_act[i]-color_out_BP_cued[0]).item()]
        
        errors_1 += [npy.mean(errors[1:])]
        errors_2 += [npy.mean(excluded_errors)]
    correct_token_err_out = npy.mean(npy.array(correct_token_err))
    correct_token_chosen_err_out = npy.mean(npy.array(correct_token_chosen_err))
    errors = npy.mean(npy.array(errors_1))
    excluded_errors = npy.mean(npy.array(errors_2))
    
    print(locations)
    print(f"Feature swap count: {token_swap} {swap_count} out of {trial_count}")
    print("Feature swap color vector difference:", errors)
    print("Feature swap color vector difference exlcuded:", excluded_errors)
    return [token_swap / trial_count, swap_count / trial_count, correct_token_err_out, correct_token_chosen_err_out, errors, excluded_errors]

@torch.no_grad()
def fig_feature_swap(vae: VAE_CNN, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    
    if load_data is False:
        vae.eval()
        print("addressability figure")
        # store 2 digits, generate activations of greyscaled rep of 1 of the digits, retrieve from BP using that as a cue

        bpsize = 25000        #size of the binding pool
        token_overlap =0.3
        bpPortion = int(token_overlap *bpsize) # number binding pool neurons used for each item

        dataset = Dataset('square',{'retina':False, 'colorize':False, 'rotate':False, 'scale':True}, train=False)

        #iterate numimg 1-8, compute swap rate at each
        token_swap_rates = []
        color_swap_rates = []
        errors_list = []
        correct_token_chosen_err = []
        for numing in range(1,8):
            swaps = feature_swap_trial(dataset, vae, numing, imgsize=imgsize)
            token_swap_rates += [swaps[0]]
            color_swap_rates += [swaps[1]]
            errors_list += [[swaps[2], swaps[4]]]
            correct_token_chosen_err += [swaps[3]]
        
        data_to_pickle = {
            "token_swap_rates": token_swap_rates,
            "color_swap_rates": color_swap_rates,
            "errors_list": errors_list,
            "correct_token_chosen_err": correct_token_chosen_err
        }

        joblib.dump(data_to_pickle, pkl_path)

    else:
        if not os.path.exists(pkl_path):
            raise Exception(f"No data exists for plot: {folder_path}{log_function_name()}")
        
        # load plotting data
        loaded_data = joblib.load(pkl_path)
        token_swap_rates = loaded_data["token_swap_rates"]
        color_swap_rates = loaded_data["color_swap_rates"]
        errors_list = loaded_data["errors_list"]
        correct_token_chosen_err = loaded_data["correct_token_chosen_err"]

    # % an incorrect token is selected
    sns.lineplot(x=range(1, 8), y=token_swap_rates)
    plt.xlabel('Number of items')
    plt.ylabel('Token swap rate')
    plt.savefig(f'{folder_path}token_swap_rate.png')
    plt.close()
    
    # % the correct token is selected but the incorrect square is chosen
    sns.lineplot(x=range(1, 8), y=color_swap_rates)
    plt.xlabel('Number of items')
    plt.ylabel('Feature swap rate')
    plt.savefig(f'{folder_path}feature_swap_rate.png')
    plt.close()

    # error between selected color and true color  
    sns.lineplot(x=range(1, 8), y=[e[0] for e in errors_list], label='Correct items')
    sns.lineplot(x=range(1, 8), y=[e[1] for e in errors_list], label='Other items')
    sns.lineplot(x=range(1, 8), y=correct_token_chosen_err, label='Correct token chosen')
    plt.xlabel('Number of items')
    plt.ylabel('MSE latent color vector')
    plt.legend()
    plt.savefig(f'{folder_path}feature_error.png')
    plt.close()

@torch.no_grad()
def fig_encoding_flexibility(vae: VAE_CNN, folder_path: str, load_data: bool = False):
    pkl_path = f'{folder_path}{log_function_name()}-figure_data.pkl'
    
    vae.eval()
    print("encoding flexibility figure")


    numimg = 2

    bpsize = 25000#00         #size of the binding pool
    token_overlap =0.35
    bpPortion = int(token_overlap *bpsize) # number binding pool neurons used for each item
    targetset = list(range(0, 4))
    targetset.append(15)
    #dataset = Dataset('emnist',{'retina':True, 'colorize':True, 'rotate':False, 'scale':True, 'target_set':targetset}, train=False)
    dataset = Dataset('emnist',{'retina':True, 'colorize':True, 'rotate':False, 'scale':True, 'target_set':[0, 1, 2, 3, 4, 15]}, train=True)
    test_loader = dataset.get_loader(numimg)
    dataiter = iter(test_loader)
    imgs = next(dataiter)[0][0].cuda()

    #push the images through the encoder
    activations = vae.activations(imgs.view(-1,3,64,64), True)
    shape_act = activations['shape']
    color_act = activations['color']
    location_act = activations['location']
    scale_act = activations['scale']
    theta_orig = torch.cat([scale_act, location_act], 1)
    color_degraded = []
    shape_degraded = []

    crop, theta = vae.stn_encode(imgs.view(-1,3,64,64))

    # degrade shape encoding weight: 1 -> 0.2
    for n in range (1,10,2):
        BP_activations_sc = {'shape': [shape_act.view(numimg,-1), 1/n], 'color': [color_act.view(numimg,-1), 1], 
                             'location': [location_act.view(numimg,-1), 1], 'scale': [scale_act.view(numimg,-1), 1]}
        
        
        #now store/retrieve from L1
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_sc, numimg,normalize_fact_novel)
        BP_act_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_sc, numimg,normalize_fact_novel)


        # then through BP
        #bp_crop_recon = vae.decoder_cropped(BP_act_out['shape'], BP_act_out['color'])

        shape_out_BP, color_out_BP = BP_act_out['shape'], BP_act_out['color']
        location_out_BP, scale_out_BP = BP_act_out['location'], BP_act_out['scale']

        theta = torch.cat([scale_out_BP, location_out_BP], 1)
    
        BP_retinal_recon = vae.decoder_retinal(shape_out_BP, color_out_BP, theta)
        shape_degraded += [BP_retinal_recon]
    
    # degrade color encoding weight: 1 -> 0.2
    for n in range (1,10,2):
        BP_activations_sc = {'shape': [shape_act.view(numimg,-1), 1], 'color': [color_act.view(numimg,-1), 1/n], 
                             'location': [location_act.view(numimg,-1), 1], 'scale': [scale_act.view(numimg,-1), 1]}
        
        #now store/retrieve from L1
        BPOut, Tokenbindings = BPTokens_storage(bpsize, bpPortion, BP_activations_sc, numimg,normalize_fact_novel)
        BP_act_out = BPTokens_retrieveByToken( bpsize, bpPortion, BPOut, Tokenbindings, BP_activations_sc, numimg,normalize_fact_novel)
        
        shape_out_BP, color_out_BP = BP_act_out['shape'], BP_act_out['color']
        location_out_BP, scale_out_BP = BP_act_out['location'], BP_act_out['scale']

        theta = torch.cat([scale_out_BP, location_out_BP], 1)
        BP_retinal_recon = vae.decoder_retinal(shape_out_BP, color_out_BP, theta)
        color_degraded += [BP_retinal_recon]
    degraded = [x for pair in zip(shape_degraded, color_degraded) for x in pair]
    degraded = torch.cat(degraded,0)
    sample = imgs[0: numimg].view(numimg, 3, 64, 64)

    #save an image showing:  original images, reconstructions directly from L1,  from L1 BP, from L1 BP through bottleneck, from maps BP
    save_image(torch.cat([sample, sample, degraded], 0), f'{folder_path}figure2b.png',
            nrow=numimg*2, normalize=False, pad_value=0.6)
    
    with open(f"{folder_path}params.txt", "w") as f:
        f.write(f"bpsize: {bpsize}\n")
        f.write(f"token_overlap: {token_overlap}\n")
        f.write(f"bpPortion: {bpPortion}\n")