<h2>Tensorflow-Image-Segmentation-Messidor-2-Retinal-Vessel (2025/03/01)</h2>
Sarah T. Arai<br>
Software Laboratory antillia.com<br><br>
This is the first experiment of Image Segmentation for <b>Messidor-2</b> Retinal Vessel
 based on 
the latest <a href="https://github.com/sarah-antillia/Tensorflow-Image-Segmentation-API">Tensorflow-Image-Segmentation-API</a>,
<a href="https://www.adcis.net/en/third-party/messidor2/">Messidor-2 Dataset IMAGES</a>, and 
<a href="https://drive.google.com/file/d/1v7zoHAeH3sDtojDXi76s7JB8xz5p1jXR/view?usp=sharing">
Antillia-Messidor-2-LABELS-V2</a>.<br>

<br>
Please see also our experiments:<br>
<li>
<a href="https://github.com/sarah-antillia/Tensorflow-Tiled-Image-Segmentation-Messidor-2-Retinal-Vessel">
Tensorflow-Tiled-Image-Segmentation-Messidor-2-Retinal-Vessel</a> based on
<a href="https://www.adcis.net/en/third-party/messidor2/">Messidor-2 Dataset IMAGES</a>
</li>

<li>
<a href="https://github.com/sarah-antillia/Tensorflow-Tiled-Image-Segmentation-Pre-Augmented-HRF-Retinal-Vessel">
Tensorflow-Tiled-Image-Segmentation-Pre-Augmented-HRF-Retinal-Vessel</a> based on
<a href="https://www5.cs.fau.de/research/data/fundus-images/">High-Resolution Fundus (HRF) Image Database</a>
</li>
<li>
<a href="https://github.com/sarah-antillia/Tensorlfow-Tiled-Image-Segmentation-Pre-Augmented-DRIVE-Retinal-Vessel">
Tensorflow-Tiled-Image-Segmentation-Pre-Augmented-DRIVE-Retinal-Vessel</a> based on 
<a href="https://drive.grand-challenge.org/">DRIVE: Digital Retinal Images for Vessel Extraction</a>
</li>
<li>
<a href="https://github.com/sarah-antillia/Tensorflow-Tiled-Image-Segmentation-Pre-Augmented-STARE-Retinal-Vessel">
Tensorflow-Tiled-Image-Segmentation-Pre-Augmented-STARE-Retinal-Vessel</a> baased on 
<a href="https://cecas.clemson.edu/~ahoover/stare/">STructured Analysis of the Retina</a>.
<br>
</li>
<li>
<a href="https://github.com/sarah-antillia/Tensorflow-Image-Segmentation-FIVES-Retinal-Vessel">
Tensorflow-Image-Segmentation-FIVES-Retinal-Vessel</a> based on <a href="https://figshare.com/articles/figure/FIVES_A_Fundus_Image_Dataset_for_AI-based_Vessel_Segmentation/19688169?file=34969398">
FIVES: A Fundus Image Dataset for AI-based Vessel Segmentation</a>.
</li>
<li>
<a href="https://github.com/sarah-antillia/Tensorflow-Image-Segmentation-Retinal-Vessel">
Tensorflow-Image-Segmentation-Retinal-Vessel</a> based on <a href="https://researchdata.kingston.ac.uk/96/">CHASE_DB1 dataset</a>.
</li>
<br>

<br>
<hr>
<b>Actual Image Segmentation for Messidor-2 IMAGES of 2240x1488 pixels</b><br>
As shown below, the inferred masks look similar to the ground truth masks. <br>
<table>
<tr>
<th>Input: image</th>
<th>Mask (antillia-ground_truth-v2)</th>
<th>Prediction: inferred_mask</th>
</tr>
<tr>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/images/20051020_44261_0100_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/masks/20051020_44261_0100_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test_output/20051020_44261_0100_PP.jpg" width="320" height="auto"></td>
</tr>

<tr>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/images/20051020_45004_0100_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/masks/20051020_45004_0100_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test_output/20051020_45004_0100_PP.jpg" width="320" height="auto"></td>
</tr>

<tr>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/images/20051130_60234_0400_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/masks/20051130_60234_0400_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test_output/20051130_60234_0400_PP.jpg" width="320" height="auto"></td>
</tr>
</table>

<hr>
<br>
In this experiment, we used the simple UNet Model 
<a href="./src/TensorflowUNet.py">TensorflowSlightlyFlexibleUNet</a> for this Messidor-2 Segmentation Model.<br>
As shown in <a href="https://github.com/sarah-antillia/Tensorflow-Image-Segmentation-API">Tensorflow-Image-Segmentation-API</a>.
you may try other Tensorflow UNet Models:<br>

<li><a href="./src/TensorflowSwinUNet.py">TensorflowSwinUNet.py</a></li>
<li><a href="./src/TensorflowMultiResUNet.py">TensorflowMultiResUNet.py</a></li>
<li><a href="./src/TensorflowAttentionUNet.py">TensorflowAttentionUNet.py</a></li>
<li><a href="./src/TensorflowEfficientUNet.py">TensorflowEfficientUNet.py</a></li>
<li><a href="./src/TensorflowUNet3Plus.py">TensorflowUNet3Plus.py</a></li>
<li><a href="./src/TensorflowDeepLabV3Plus.py">TensorflowDeepLabV3Plus.py</a></li>

<br>
<h3>1. Dataset Citation</h3>

We  used <a href="https://www.adcis.net/en/third-party/messidor2/">Messidor-2 Dataset</a>,<br><br>
MESSIDOR stands for <b>M</b>ethods to <b>E</b>valuate <b>S</b>egmentation and <b>I</b>ndexing <b>T</b>echniques in the field of 
<b>R</b>etinal <b>O</b>phthalmology (in French).<br>
<br>
<b>Messidor-2 Dataset</b><br>
The Messidor-2 dataset is a collection of Diabetic Retinopathy (DR) examinations, each consisting of two macula-centered eye fundus images (one per eye).
Part of the dataset (Messidor-Original) was kindly provided by the Messidor program partners. 
The remainder (Messidor-Extension) consists of never-before-published examinations from Brest University Hospital.
In the original Messidor dataset, some fundus images came in pairs, some others were single. 
Messidor-Original consists of all image pairs from the original Messidor dataset, that is 529 examinations (1058 images, 
saved in PNG format).
In order to populate Messidor-Extension, diabetic patients were recruited in the Ophthalmology department of 
Brest University Hospital (France) between October 16, 2009 and September 6, 2010. Eye fundi were imaged, 
without pharmacological dilation, using a Topcon TRC NW6 non-mydriatic fundus camera with a 45 degree field of 
view. Only macula-centered images were included in the dataset. <br>
Messidor-Extension contains 345 examinations (690 images, in JPG format).<br>
Overall, Messidor-2 contains 874 examinations (1748 images). 
The dataset comes with a spreadsheet containing image pairing. 
<b>It does not contain annotations such as a diabetic retinopathy “ground truth”.
 However, some third-parties proposed such annotations, but these are independent from the official Messidor-2 database,
  and therefore not handled by our services.</b><br>
  <br>
<b>Using the database</b><br>
Messidor-2 can be used, free of charge, for research and educational purposes. Copy, redistribution, 
and any unauthorized commercial use are prohibited. 
Any publication relying on this dataset must acknowledge the 
<a href="https://latim.univ-brest.fr/index.php?lang=en&lang=en">LaTIM laboratory</a> and the Messidor program partners.
Please include the following acknowledgmen.<br>

Kindly provided by the Messidor program partners (see https://www.adcis.net/en/third-party/messidor/).
<br>
Decencière et al..<br>
Feedback on a publicly distributed database: the Messidor database.<br>
Image Analysis & Stereology, v. 33, n. 3, p. 231-234, aug. 2014. ISSN 1854-5165.<br>
Available at: http://www.ias-iss.org/ojs/IAS/article/view/1155 or
http://dx.doi.org/10.5566/ias.1155.

M. D. Abràmoff, J. C. Folk, D. P. Han, J. D. Walker, D. F. Williams, S. R. Russell, P. Massin, B. Cochener,<br>
 P. Gain, L. Tang, M. Lamard, D. C. Moga, G. Quellec, and M. Niemeijer,<br>
Automated analysis of retinal images for detection of referable diabetic retinopathy.<br>
JAMA Ophthalmol, vol. 131, no. 3, Mar. 2013, p. 351–357.<br>
Available at: https://doi.org/10.1001/jamaophthalmol.2013.1743.<br>
<br>


<h3>2. Messidor-2 IMAGES and LABELS </h3>
<h3>2.1 Download Messidor-2 IMAGES Dataset</h3>
Please download <a href="https://www.adcis.net/en/third-party/messidor2/">Messidor-2 Dataset</a>,
and place IMAGES under Messidor-2-master folder as shown below.
<pre>
./projects
 └─generator
    └─Messidor-2-master
        └─IMAGES
</pre>

<h3>2.2 Download Messidor-2 LABELS</h3>
Please download our own Messidor-2 LABELS <a href="https://drive.google.com/file/d/1v7zoHAeH3sDtojDXi76s7JB8xz5p1jXR/view?usp=sharing">
Antillia-Messidor-2-LABELS-V2.zip</a>,
and place it under Messidor-2-master folder as shown below.

<pre>
./projects
 └─generator
    └─Messidor-2-master
        ├─IMAGES
        └─LABELS
</pre>

<h3>2.3 Split Messidor-2-master</h3>
Please move to "./projects/generator" folder and run the following Python script.<br>
<pre>
python spit_master.py
</pre>
,by which the following Messidor-2 dataset will be created.
<pre>
./dataset
└─Messidor-2
    ├─test
    │   ├─images
    │   └─masks
    ├─train
    │   ├─images
    │   └─masks
    └─valid
        ├─images
        └─masks
</pre>
This is a 2240x1488 pixels images and their corresponding masks dataset.<br>
.<br>

<br>
<b>Messidor-2 Statistics</b><br>
<img src ="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/Messidor-2_Statistics.png" width="512" height="auto"><br>
<br>
As shown above, the number of images of train and valid datasets is enough 
to use for a training set of our segmentation model.
<br>

<br>
<b>Train_images_sample</b><br>
<img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/asset/train_images_sample.png" width="1024" height="auto">
<br>
<b>Train_masks_sample</b><br>
<img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/asset/train_masks_sample.png" width="1024" height="auto">
<br>

<h3>
3 Train TensorflowUNet Model
</h3>
 We have trained Messidor-2TensorflowUNet Model by using the following
<a href="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/train_eval_infer.config"> <b>train_eval_infer.config</b></a> file. <br>
Please move to ./projects/TensorflowSlightlyFlexibleUNet/Messidor-2 and run the following bat file.<br>
<pre>
>1.train.bat
</pre>
, which simply runs the following command.<br>
<pre>
>python ../../../src/TensorflowUNetTrainer.py ./train_eval_infer.config
</pre>
<hr>

<b>Model parameters</b><br>
Defined a small <b>base_filters</b> and large <b>base_kernels</b> for the first Conv Layer of Encoder Block of 
<a href="./src/TensorflowUNet.py">TensorflowUNet.py</a> 
and a large num_layers (including a bridge between Encoder and Decoder Blocks).
<pre>
[model]
base_filters   = 16
base_kernels   = (9,9)
num_layers     = 8
</pre>

<b>Learning rate</b><br>
Defined a small learning rate.  
<pre>
[model]
learning_rate  = 0.0001
</pre>

<b>Online augmentation</b><br>
Disabled our online augmentation.  
<pre>
[model]
model         = "TensorflowUNet"
generator     = False
</pre>

<b>Loss and metrics functions</b><br>
Specified "bce_dice_loss" and "dice_coef".<br>
<pre>
[model]
loss           = "bce_dice_loss"
metrics        = ["dice_coef"]
</pre>
<b>Learning rate reducer callback</b><br>
Enabled learing_rate_reducer callback, and a small reducer_patience.
<pre> 
[train]
learning_rate_reducer = True
reducer_factor     = 0.4
reducer_patience   = 4
</pre>


<b>Early stopping callback</b><br>
Enabled early stopping callback with patience parameter.
<pre>
[train]
patience      = 10
</pre>
<b>Color space conversion</b><br>
Used cv2.COLOR_BGR2Luv color space converter.
<pre>
[image]
color_converter = "cv2.COLOR_BGR2Luv"
</pre>

<b>Epoch change inference callbacks</b><br>
Enabled epoch_change_infer callback.<br>
<pre>
[train]
epoch_change_infer       = True
epoch_change_infer_dir   =  "./epoch_change_infer"
epoch_changeinfer        = False
epoch_changeinfer_dir    = "./epoch_changeinfer"
num_infer_images         = 6
</pre>

By using this callback, on every epoch_change, the inference procedure can be called
 for an image in <b>mini_test</b> folder. This will help you confirm how the predicted mask changes 
 at each epoch during your training process.<br> <br> 

<b>Epoch_change_inference output at starting (1,2,3,4)</b><br>
<img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/asset/epoch_change_infer_start.png" width="1024" height="auto"><br>
<br>
<br>

<b>Epoch_change_inference output at ending (97,98,99,100)</b><br>
<img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/asset/epoch_change_infer_end.png" width="1024" height="auto"><br>
<br>
<br>
In this experiment, the training process was terminated at epoch 100.<br><br>
<img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/asset/train_console_output_at_epoch_100.png" width="720" height="auto"><br>
<br>

<br>
<a href="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/eval/train_metrics.csv">train_metrics.csv</a><br>
<img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/eval/train_metrics.png" width="520" height="auto"><br>

<br>
<a href="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/eval/train_losses.csv">train_losses.csv</a><br>
<img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/eval/train_losses.png" width="520" height="auto"><br>

<br>

<h3>
4 Evaluation
</h3>
Please move to a <b>./projects/TensorflowSlightlyFlexibleUNet/Messidor-2</b> folder,<br>
and run the following bat file to evaluate TensorflowUNet model for Messidor-2.<br>
<pre>
./2.evaluate.bat
</pre>
This bat file simply runs the following command.
<pre>
python ../../../src/TensorflowUNetEvaluator.py ./train_eval_infer.config
</pre>

Evaluation console output:<br>
<img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/asset/evaluate_console_output_at_epoch_100.png" width="720" height="auto">
<br><br>

<a href="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/evaluation.csv">evaluation.csv</a><br>

The loss (bce_dice_loss) to this Messidor-2/test was not so low, and dice_coef not so high as shown below.
<br>
<pre>
loss,0.1224
dice_coef,0.8402
</pre>
<br>

<h3>
5 Inference
</h3>
Please move to a <b>./projects/TensorflowSlightlyFlexibleUNet/Messidor-2</b> folder<br>
,and run the following bat file to infer segmentation regions for images by the Trained-TensorflowUNet model for Messidor-2.<br>
<pre>
./3.infer.bat
</pre>
This simply runs the following command.
<pre>
python ../../../src/TensorflowUNetInferencer.py ./train_eval_infer.config
</pre>
<hr>
<b>mini_test_images (2048x2048 pixels)</b><br>
<img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/asset/mini_test_images.png" width="1024" height="auto"><br>
<b>mini_test_mask(ground_truth)</b><br>
<img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/asset/mini_test_masks.png" width="1024" height="auto"><br>

<hr>
<b>Inferred test masks (2048x2048 pixels)</b><br>
<img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/asset/mini_test_output.png" width="1024" height="auto"><br>
<br>
<hr>
<b>Enlarged images and masks of 2240x1488 pixels</b><br>

<table>
<tr>
<th>Image</th>
<th>Mask (antillia-ground_truth-v2)</th>
<th>Inferred-mask</th>
</tr>
<tr>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/images/20051020_45004_0100_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/masks/20051020_45004_0100_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test_output/20051020_45004_0100_PP.jpg" width="320" height="auto"></td>
</tr>
<tr>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/images/20051020_44338_0100_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/masks/20051020_44338_0100_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test_output/20051020_44338_0100_PP.jpg" width="320" height="auto"></td>
</tr>
<tr>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/images/20051021_39552_0100_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/masks/20051021_39552_0100_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test_output/20051021_39552_0100_PP.jpg" width="320" height="auto"></td>
</tr>
<tr>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/images/20051116_44718_0400_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/masks/20051116_44718_0400_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test_output/20051116_44718_0400_PP.jpg" width="320" height="auto"></td>
</tr>
<tr>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/images/20051202_36970_0400_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/masks/20051202_36970_0400_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test_output/20051202_36970_0400_PP.jpg" width="320" height="auto"></td>
</tr>
<tr>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/images/20051212_36640_0400_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test/masks/20051212_36640_0400_PP.png" width="320" height="auto"></td>
<td><img src="./projects/TensorflowSlightlyFlexibleUNet/Messidor-2/mini_test_output/20051212_36640_0400_PP.jpg" width="320" height="auto"></td>
</tr>
</table>
<hr>
<br>
<h3>
<h3>
References
</h3>
<b>1. Locating Blood Vessels in Retinal Images by Piecewise Threshold Probing of a Matched Filter Response</b><br>
Adam Hoover, Valentina Kouznetsova, and Michael Goldbaum<br>
<a href="https://www.uhu.es/retinopathy/General/000301IEEETransMedImag.pdf">
https://www.uhu.es/retinopathy/General/000301IEEETransMedImag.pdf
</a>
<br>
<br>
<b>2. High-Resolution Fundus (HRF) Image Database</b><br>
Budai, Attila; Bock, Rüdiger; Maier, Andreas; Hornegger, Joachim; Michelson, Georg.<br>
<a href="https://www5.cs.fau.de/research/data/fundus-images/">
https://www5.cs.fau.de/research/data/fundus-images/
</a>.
<br>
<br>
<b>3. Robust Vessel Segmentation in Fundus Images</b><br>
Budai, Attila; Bock, Rüdiger; Maier, Andreas; Hornegger, Joachim; Michelson, Georg.<br>

<a href="https://onlinelibrary.wiley.com/doi/10.1155/2013/154860">
https://onlinelibrary.wiley.com/doi/10.1155/2013/154860
</a>
<br>
<br>
<b>4. State-of-the-art retinal vessel segmentation with minimalistic models</b><br>
Adrian Galdran, André Anjos, José Dolz, Hadi Chakor, Hervé Lombaert & Ismail Ben Ayed<br>
<a href="https://www.nature.com/articles/s41598-022-09675-y">
https://www.nature.com/articles/s41598-022-09675-y
</a>
<br>
<br>
<b>5. Retinal blood vessel segmentation using a deep learning method based on modified U-NET model</b><br>
Sanjeewani, Arun Kumar Yadav, Mohd Akbar, Mohit Kumar, Divakar Yadav<br>
<a href="https://www.semanticscholar.org/reader/f5cb3b1c69a2a7e97d1935be9d706017af8cc1a3">
https://www.semanticscholar.org/reader/f5cb3b1c69a2a7e97d1935be9d706017af8cc1a3</a>
<br>
<br>
<b>6. Tensorflow-Tiled-Image-Segmentation-Pre-Augmented-STARE-Retinal-Vessel</b><br>
Toshiyuki Arai @antillia.com<br>
<a href="https://github.com/sarah-antillia/Tensorflow-Tiled-Image-Segmentation-Pre-Augmented-STARE-Retinal-Vessel">
https://github.com/sarah-antillia/Tensorflow-Tiled-Image-Segmentation-Pre-Augmented-STARE-Retinal-Vessel</a>
<br>
<br>
<b>7, Tensorflow-Tiled-Image-Segmentation-Pre-Augmented-HRF-Retinal-Vessel</b><br>
Toshiyuki Arai @antillia.com<br>
<a href="https://github.com/sarah-antillia/Tensorflow-Tiled-Image-Segmentation-Pre-Augmented-HRF-Retinal-Vessel">
https://github.com/sarah-antillia/Tensorflow-Tiled-Image-Segmentation-Pre-Augmented-HRF-Retinal-Vessel</a>
<br>
<br>


