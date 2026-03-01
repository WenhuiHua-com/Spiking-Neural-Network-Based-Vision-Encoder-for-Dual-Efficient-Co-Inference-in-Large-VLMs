# Spiking Neural Network Based Vision Encoder for Dual-Efficient Co-Inference in Large VLMs
Test code for articles submitted to IEEE Transactions on Circuits and Systems for Video Technology. If you think it's useful, please give it a star. Thank you！

## Requirements
Dependencies can be found in requirements.txt

## Download the pre-trained codebook or model from the link below and place them in the designated directory: 
Pre-trained BLIP weights and BERT need to be downloaded before running. 

[BLIP weights used in this paper]: (https://drive.google.com/file/d/1EZkJJwYI7zcoDOUaTDXJb_piSAp0zt_a/view?usp=sharing) #In this paper, The BERT weights should be placed in the BERT folder（https://drive.google.com/drive/folders/1pZAzqDwhJMvo_N9JPB1pANfjMkNlqfGe?usp=sharing）.

In order to run the feature coding for machine algorithm proposed in this paper, it is also necessary to download the codebook：
[codebook]:([https://drive.google.com/file/d/1jv3pt70uSgXHUaRnpFujRQKNYIpAdNC0/view?usp=drive_link](https://drive.google.com/file/d/10oyimLxlY2ju7rbOC31DbmhKYXEjO6r7/view?usp=sharing))

The spikingjelly computing unit is needed：
[spikingjelly]:(https://drive.google.com/drive/folders/1cRIdTsZMOKcs6GpSeaRJX8JOc25Sgi3Y?usp=sharing)

SNN weights：
[Spike-Driven Transformer]:([https://drive.google.com/drive/folders/1cRIdTsZMOKcs6GpSeaRJX8JOc25Sgi3Y?usp=sharing](https://drive.google.com/file/d/1jg8la2Ncq0kTh8OvczKpEQXsEG1celZn/view?usp=drive_link))

RKNN weights：
[RKNN]:([https://drive.google.com/file/d/1YcCnTSAU6CysEmaC2Alz7pT6Q_oljZvc/view?usp=sharing])


## Data preparation
Please place your dataset files as follows before running any scripts:

flick/ ├── annotation/ │ └── <annotation files> └── flickr30k-images/ └── flickr30k-images/ └── <image files>

- **annotation/**: Contains all annotation files.
- **flickr30k-images/**: The main folder for the Flickr30k dataset images.
  - **flickr30k-images/**: Subfolder with the actual image files.

Make sure to update the dataset paths in your configuration or script parameters accordingly. Also be careful to modify the path in retrieval_flickr.yaml.
## Test VLM task：image caption

To generate a caption for an image with SNN encoder:

<pre> python test_spike_caption.py  </pre> 

After running, some results will be output as follows:

Loading codebook sets

Creating model

loading spikeformer successfully

flickr30k-images/1921102799.jpg 100 ['a young boy playing soccer in a field']

flickr30k-images/2504007911.jpg 200 ['a man riding a bike in front of a building']

flickr30k-images/2900560501.jpg 300 ['a group of people in a room']

flickr30k-images/327955368.jpg 400 ['a group of birds in a park']

flickr30k-images/3671851846.jpg 500 ['a woman standing in a field']

flickr30k-images/428979011.jpg 600 ['a man in a yellow shirt and a yellow hat']

flickr30k-images/4700788144.jpg 700 ['a man riding a bike on a trail']

flickr30k-images/4915716087.jpg 800 ['a man driving a horse drawn carriage']

flickr30k-images/6278649113.jpg 900 ['a person doing a trick on a skateboard']

flickr30k-images/97234558.jpg 1000 ['a person standing on the beach']

## Running in RKNN chip
We conducted testing on the RK3576 chip. The specific code is located in the "rk3576" folder, and the steps to run it are as follows:

1. Make sure your platform is RK3576
2. Copy "rknn_run_3576.py", "tcpserver.py" and "Rknn_3576_20250703.rknn" to your board
3. You may need to modify the RKNN_MODEL_PATH in the "rknn_run_3576.py" file to point to the location of the rknn model
4. Use ```python3 rknn_run_3576.py``` to run

## follow-up work
After the review finished, the training code will be updated.
## References
The code is implemented based on [BLIP]: (https://github.com/salesforce/BLIP)， [Spike-Driven-Transformer]:(https://github.com/BICLab/Spike-Driven-Transformer) . We thank the contributors for their great work!
## Some renderings based on the proposed methods in this paper
 [Visual interpretation]
---
![](vis_sim.jpg)

 [UAV_test_interpretation]
---
<img src="vis_real.jpg" width="60%">

