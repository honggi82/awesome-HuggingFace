# arXiv:2409.04196v2[cs.CV]16Apr2025

## GST: Precise 3D Human Body from a Single Image with Gaussian Splatting Transformers

Lorenza Prospero1,2 Abdullah Hamdi2 Joao F. Henriques2 Christian Rupprecht2

1The Podium Institute for Sports Medicine and Technology, University of Oxford 2Visual Geometry Group, University of Oxford

{lorenza,abdullah,joao,chrisr}@robots.ox.ac.uk

Input Image Other Views HMR2 [12] GST (ours) Input Image Other Views HMR2 [12] GST (ours)

[Figure 1]

Figure 1. Example of human pose improvements using our method GST. 3D human body results of our GST and SMPL predictions of HMR2 [12] on a sports sequence from the CMU panoptic dome dataset [20].

#### Abstract

an effective auxiliary objective to refine 3D pose estimation by accounting for clothes and other geometric variations. The code is available at https://github.com/prosperolo/GST.

Reconstructing posed 3D human models from monocular images has important applications in the sports industry, including performance tracking, injury prevention and virtual training. In this work, we combine 3D human pose and shape estimation with 3D Gaussian Splatting (3DGS), a representation of the scene composed of a mixture of Gaussians. This allows training or fine-tuning a human model predictor on multi-view images alone, without 3D ground truth. Predicting such mixtures for a human from a single input image is challenging due to self-occlusions and dependence on articulations, while also needing to retain enough flexibility to accommodate a variety of clothes and poses. Our key observation is that the vertices of standardized human meshes (such as SMPL) can provide an adequate spatial density and approximate initial position for the Gaussians. We can then train a transformer model to jointly predict comparatively small adjustments to these positions, as well as the other 3DGS attributes and the SMPL parameters. We show empirically that this combination (using only multi-view supervision) can achieve near real-time inference of 3D human models from a single image without expensive diffusion models or 3D points supervision, thus making it ideal for the sport industry at any level. More importantly, rendering is

#### 1. Introduction

Creating posed 3D human models from monocular images is crucial for the sports industry since reliably detecting the shape and pose of all humans in the scene is a fundamental prerequisite for any system monitoring players’ health or performance. A reliable system monitoring players’ poses throughout different games could be used to analyze their skills training, monitor return to play after injury, and influence game regulations to make the sport safer. These products require precise 3D rendering, speed, compactness, and flexibility to be practical and economically viable for teams at any level.

Popular approaches like HMR2 [12] regress the parameters of a human body model such as SMPL [29]. However, these approaches require ground truth 3D pose and shape annotations for every training frame. Therefore, they require significant time and economic investment for data collection before training in any new domain. This makes these methods unsuitable for training in any specific sports setup. Moreover, SMPL can only model the shape of the human

- Table 1. Single Image 3D Human Reconstruction Methods. Comparison of various 3D representation models, highlighting key attributes such as speed, method of obtaining the model, type of 3D representation, usage of diffusion prior, and supervision technique.

Method Speed Obtained by 3D Representation Diffusion Prior Supervision PIFU [39] 10 seconds Inference SDF ✗ Direct 3D HumanLRM [43] 7 seconds Inference NeRF (Triplane) ✓ Direct 3D + MV SiTH [14] 2 minutes Inference SDF ✓ Direct 3D SIFU [54] 6 minutes Optimization SDF ✓ Direct 3D GTA [53] 0.55 seconds Optimization SDF ✗ Direct 3D SHERT [48] 23 seconds Inference Mesh ✓ Direct 3D R2Human [8] 0.04 seconds Inference NeRF (MLP) ✗ Direct 3D ConTex-Human [10] 60 minutes Optimization NeRF+Mesh ✓ Direct 3D SHERF [15] 0.75 seconds Inference NeRF (MLP) ✗ Multi-View GST (ours) 0.02s seconds Inference Gaussian Splatting ✗ Multi-View

body and cannot account for clothing or hair deformations.

Modeling intricate 3D details and deformations of facial features, clothing, and hair is a long-standing challenge for deep learning methods. Early methods addressed these challenges using a learned Signed Distance Function (SDF) on a human template to predict detailed 3D meshes [39, 53]. Later works incorporated Neural Radiance Fields (NeRFs) to capture texture details [15, 43] or leveraged pre-trained diffusion models to generate dense views from a single frontal image, reducing prediction ambiguity [4, 10, 14, 43, 48, 54]. Despite the good visual quality of the results, these methods suffer from low speed, hindering real-time deployment, and often require expensive 3D scans as supervision.

In this work, we present GST (Gaussian Splatting Transformer), illustrated in Fig. 2, a direct method that learns to predict 3D Gaussian Splatting [22] as 3D representation, allowing for fast rendering and flexible editing abilities compared to others. Our method does not rely on diffusion priors and is, therefore, capable of near real-time predictions. GST leverages multi-view supervision instead of precise (and expensive) 3D point clouds. Despite this, it predicts accurate 3D joint and body poses while maintaining the perceptual quality of renderings from novel views. Table 1 summarizes the characteristics of prior work.

GST is inspired by recent works on single-view 3D reconstruction [41]. However, the complexity of human pose in 3D space poses significant challenges to the direct applications of methods that associate one 3D point (or Gaussian) to each pixel. Therefore, we also augment our model to predict the pose parameters of the SMPL [29] model. The SMPL model is used as the scaffolding on which the Gaussians are positioned and rendered. Each Gaussian is loosely tied to a vertex on the SMPL model by an offset. This has two advantages. First, it provides a good initialization of the density and pose of the Gaussians, including back faces, which are notoriously difficult for single-view methods. Second, we find that the joint optimization of pose and appearance

improves the SMPL pose prediction.

To the best of our knowledge, GST is the first work that efficiently combines fast and accurate 3D pose human prediction with improved geometry, utilizing only multi-view supervision and without relying on diffusion priors. In summary, our contributions are the following:

Contributions: (i) We propose GST, a 3D human body model prediction method that does not rely on diffusion priors and performs novel view synthesis and human pose estimation from a single image input. This makes it particularly amenable to real-time modeling tasks, where multiple views are uneconomical or impractical. (ii) We evaluate our method and compare it to other state-of-the-art models. In contrast to prior methods that only solve for 3D pose estimation or 3D reconstruction, our method can predict both without 3D supervision, making it suitable for training and deployment on any specific sports setup.

- 2. Related work
- 3D Human Pose Estimation. Many approaches in the literature focus on predicting 3D human pose and shape from a single image [5, 12, 21, 24, 26, 27]. The approaches that directly regress the body shape and pose from a single image are most relevant to our work. The first work to introduce this approach was HMR [21], which uses a CNN to regress SMPL [29] parameters. Dedicated designs have been proposed for the HMR architecture; HoloPose [13] suggests a pooling strategy based on the 2D locations of body joints, while HKMR [11] relies on SMPL hierarchical structure to make predictions. PARE [23] introduces a body-part-guided attention mechanism to handle occlusions better, and PyMAF [49, 50] incorporates a mesh alignment module for SMPL parameter regression. More recently, HMR2 [12] utilizes a transformer to predict the SMPL parameters and train on a large pool of 3D data and unprotected 2D joint labels. In contrast, TokenHMR [7] improved HMR2 by leveraging tokenized encoding and reduced the 2D basis in training HMR2.

[Figure 2]

[Figure 3]

[Figure 4]

[Figure 5]

[Figure 6]

[Figure 7]

|[Figure 8]|
|---|

[Figure 9]

[Figure 10]

Output SMPL

[Figure 11]

SMPL Query Token

[Figure 12]

###### (𝜃,𝛽)

[Figure 13]

###### MLP

ViT

Multi-View Image Datasets (no 3D GT)

Tightness Loss |𝛿|2

Image Loss |I-IGT|

[Figure 14]

[Figure 15]

[Figure 16]

Input ImageX

Multi-View Renderings I

Color c Opacity 𝛼 Scale Rotation Offset 𝛿

( H ⨉ W ⨉ 3 )

[Figure 17]

( M ⨉ H ⨉ W ⨉ 3 )

Transformer Blocks w/ Cross Attn

[Figure 18]

MLP

[Figure 19]

[Figure 20]

[Figure 21]

Output Gaussian Splats

Rendering

[ 𝜇, Σ, 𝛼, c ] 𝜇 = v + 𝛿

Query Tokens

GST

- Figure 2. Overview of the pipeline of Gaussian Splatting Transformer (GST). Given a single input image, GST uses a Vision Transformer (ViT) to predict both the 3D human pose (in the form of SMPL parameters) and a refined full-color 3D model (in the form of 3D Gaussian Splats). Additional input tokens are used to predict each Gaussian color c, opacity α, scale, rotation, and position offset δ. Every Gaussian position µ is tied to one vertex of the SMPL model v by the offset δ.

In contrast to all these methods, our GST does not rely on 3D supervision and utilizes novel view synthesis training of a transformer to predict the Gaussian splats grounded on predicted SMPL parameters. Similar to our method, A-NeRF [40] jointly optimizes human pose and 3D reconstruction. However, it takes videos as input and does not generalise to unseen subjects.

and texture colours, while HumanLRM [43] generates multiviews with a pre-trained diffusion model and then trains a tri-plane NeRF Large Reconstruction Model (LRM) for decoding. ELICIT [17] leverages CLIP [34] to generate text-conditioned unseen regions. SHERT [48] utilizes semantic mesh and whole texture inpainting with the help of diffusion priors to create detailed 3D meshes of humans. HumanSplat [31] and Human 3diffusion [44] use diffusion priors to generate novel views, and TeCH [18] uses text-toimage diffusion models to embed indescribable appearance information. Most of these methods rely on pre-trained diffusion models for texturing optimization, which slows down the process and limits scalability for high-speed, longduration video motion. In contrast, our GST operates without diffusion priors, achieving near real-time inference while remaining flexible and capable of integrating with priors if needed.

Single-image Human Reconstruction. Recent advancements in 3D human reconstruction from single images have resulted in diverse methods, each employing different data sources, 3D representations, and supervision strategies [4, 8, 10, 14–16, 33, 43, 47, 48, 53, 54]. PIFU [39] is one of the earlier works that successfully uses the learned Sign Distance Function (SDF) representation with direct 3D supervision to reconstruct a detailed 3D mesh of humans from a single image. ANIM [33] incorporates sparse voxel depth features with the input image features and uses direct 3D supervision to train on the RGBD input (depth is needed). SHERF [15] developed on PIFU’s 3D representation and adopted a NeRF representation for decoding the 3D human, training with multi-view supervision. While GST follows SHERF in the multi-view supervision, we utilize the more explicit Gaussian Splatting representation [22] for 3D, allowing for more flexible control and better 3D alignment.

#### 3. Gaussian Splatting Transformers (GST)

This section presents our methodology for reconstructing 3D human models from a single image using Gaussian Splatting Transformers (GST), as illustrated in Fig. 2.

##### 3.1. Architecture

With the recent wave of success of generative image and text models [30, 35–38], several methods try to leverage these foundation models to improve the performance of 3D human reconstruction [4, 8, 10, 14, 43, 54]. For example, SIFU [54] integrates GPT-predicted captions with diffusion models for back-view generation and texture refinement and builds on GTA [53], its predecessor, which learns a triplane SDF decoder. Similarly, SiTH [14] employs a diffusion prior to generate back views and decode the SDF

Our model predicts 3D Gaussian splatting parameters from a single input image using a transformer architecture, including tokenization, processing through transformer blocks, and decoding into Gaussian parameters. We detail the model architecture (Sec. 3.1) and the loss functions (Sec. 3.2).

Image Encoder Architecture. Our backbone follows HMR2 [12] and uses a ViT [6] to map an image to a series of visual tokens. The input is an RGB image X ∈ RH×W×3, which is divided into non-overlapping patches pj ∈ Rp×p×3,

with j ∈ {1,...,HW/p2}. The patches are vectorized and affinely transformed into patch tokens xj ∈ Rd.

The patch tokens are processed through a series of Transformer blocks [42]. The final output is a set of tokens yj ∈ Rd encapsulating the transformed image information. Human Shape Representation. The SMPL model [29] represents the 3D human mesh shape as a mesh. SMPL is a low-dimensional parametric model defined by pose parameters θ ∈ R24×3×3 and shape parameters β ∈ R10, outputting mesh vertices’ 3D positions v = SMPL(θ,β) ∈ R6890×3.

Decoder Architecture. We build on HMR2 [12], which predicts the SMPL representation (θ,β) from the image representation yj through a cross-attention mechanism. Specifically, a single (fixed) token tSMPL attends to all image tokens yj through a series of cross-attention layers. An MLP decodes the token into the pose parameters θ and β.

This representation could be learned with image-pose pairs (X,θ,β). However, here, we focus on multi-view supervision, as 3D supervision is costly and scarce, and not readily available for real-world setups.

To train with multi-view supervision, the model needs to generate an image. We use recent advances in fast neural rendering: Gaussian Splatting [22]. This scene representation is defined by a set of 3D Gaussians, each characterized by a mean position µ ∈ R3, a covariance matrix Σ ∈ R3×3, the opacity α ∈ R and a colour c ∈ R3.

We link the 3D body shape and pose with the Gaussian scene representation, such that each vertex vn in the mesh is assigned a Gaussian Gn = (µn,Σn,αn,cn). We allow the Gaussians to move away from the original vertex positions by a learned offset δn to model clothes and other visual shape features that the SMPL model cannot capture.

###### µn = vn + δn, (1)

This combination ensures that the 3D model captures both shape and appearance, allowing for more realistic reconstructions.

Similar to prior work [41], we factorize and simplify the covariance into the product of a rotation matrix and a diagonal matrix, enforcing a reduced number of degrees of freedom from 9 to 6: Gn ∈ R14.

It is theoretically possible to assign five tokens per Gaussian, one for each parameter: rotation, offset, scale, color, and opacity. However, this would result in over 34k tokens, which is computationally infeasible to decode with a standard Transformer. We thus group vertices into K groups, reducing the number of tokens to 5K + 1 (in practice, we set K = 26). As discussed before, the additional token is used to predict the SMPL shape parameters.

This representation allows initialization with the pretrained weights of HMR2 [12] since we only introduce additional (fixed but learned) tokens in the decoder architecture.

A set of Gaussians can be assembled from the predictions, which can be rendered into an image from any viewpoint.

##### 3.2. Loss Functions

We use a combination of losses to train our model to ensure accurate and visually realistic 3D reconstructions.

Image Reconstruction Loss. We use a combination of Mean Squared Error (MSE) to measure the difference between the M multi-view ground truth imagesˆIi and rendered images Ii, a perceptual loss to capture high-level features and textures with LPIPS metric [52], and a masked loss on the rendered opacity Iαi to remove background splats [51]:

M

2 2

1 M

+ λperceptual · LPIPS(ˆIi,Ii)

ˆIi − Ii

Limg =

i=1

2 2

+ λα M ˆ i − Iαi

,

(2) where Mˆ i is the background mask of the ground truth images ˆIi, and λperceptual and λα are weighting hyperparameters for the perceptual and transparency losses respectively. The transparency loss is necessary to reduce floating Gaussians that do not contribute to the foreground object.

Gaussian Tightness Regularization. To ensure that the predicted Gaussian Splats in Sec. 3.1 follow the SMPL parameters closely, we introduce a Gaussian tightness regularization that ensures the generated Gaussian splats [22] do not diverge and remain faithful to the underlying SMPL parameters as follows:

V

1 V

∥δn∥2 , (3)

Ltight =

n=1

where δn is defined in (1) and V = 6890 is the number of Gaussian splats (number of vertices in SMPL).

The total loss function is a weighted sum of the image losses (MSE, perceptual, and alpha) and tightness:

L = Limg + λtightLtight, (4)

where λtight is the weighting hyperparameter for the tightness regularization. As we show later in Sec. 5.3, this regularization plays an important role in the precision of the 3D human body predicted by GST. By minimizing this combined loss, our GST model learns to generate accurate human 3D models from a single image.

Optionally, a further regularization term for the SMPL shape parameters can also be included. This regularization term is an L2 loss on the β parameters. This additional term does not affect the pose or visual metrics. It only influences the predicted body thickness.

#### 4. Experiments

This section describes our evaluation setup and the baselines and prior work used in our comparisons.

##### 4.1. Datasets and Metrics

Datasets. Similar to previous works [15], we utilize four comprehensive human datasets for evaluation: THuman [55], RenderPeople [1], ZJU MoCap [32], and HuMMan [2]. For ZJU MoCap, the dataset is divided following the SHERF setup [15]. Similarly, for HuMMan, we adhere to the official split (HuMMan-Recon), using 317 sequences for training and 22 for testing, with 17 frames sampled per sequence. For THuman, we select 90 subjects for training and 10 for testing, and for the RenderPeople dataset, we randomly sample 450 subjects for training and 30 for testing. Those four datasets used for evaluation above are all small in terms of subject diversity. To showcase the capabilities of GST on a large dataset, we train our GST also on the TH21 dataset [46], which contains 2,500 3D scans with high subject diversity. We randomly selected 200 scans for evaluation. Further validation is also conducted on the CMU Panoptic dataset with the single human partition that includes 9 sequences with 31 HD camera views; some qualitative examples of the pose estimation results for the sports sequence in this dataset are shown in Fig. 1 and in the Appendix. Another dataset that could have been suitable for evaluating our method is the SportsPose dataset [19]; however, no multi-view data has been released.

Evaluation Metrics. When the Ground Truth 3D SMPL parameters are available as in RenderPeople [1] and HuMMan [2], we adopt 3D Human Joints precision MPJPE as a metric [21]. MPJPE refers to Mean Per Joint Position Error: the average L2 error across all joints after aligning with the root node. To quantitatively assess the quality of rendered novel view and novel pose images, we report peak signalto-noise ratio (PSNR), structural similarity index (SSIM), and Learned Perceptual Image Patch Similarity (LPIPS)[52]. Consistently with prior works[9, 15, 55], we project the 3D human bounding box onto each camera plane to derive the bounding box mask, subsequently reporting these metrics based on the masked regions.

Baselines. In addition to earlier work on Human NeRF with a multi-view setting, NHP [25] and MPS-NeRF [9], we compare to recent single-image methods SHERF [15] for novel view synthesis and HMR2 [12] and TokenHMR [7] for 3D Human reconstruction precision. Unlike SHERF, our method does not take as input ground truth SMPL parameters. Therefore, we adapt SHERF to use HMR2 [12] or TokenHMR [7] SMPL predictions for a fair comparison to our method. We also include a comparison with Splatter Image [41], a state-of-the-art single-image 3D reconstruction method for novel-view synthesis tables.

##### 4.2. Implementation Details of GST

Our model follows the implementation of HMR2 [12] for the prediction of the SMPL parameters. We extend the HMR2 decoder implementation to process some additional learnable

tokens for the predictions of the Gaussian parameters. The Gaussian parameters (color, rotation, scale, opacity, and offset) are predicted for K = 26 groups of 265 Gaussians. The token output is passed through a linear layer to obtain the final parameters. We use pre-trained HMR2 weights for the ViT and the decoder and freeze the ViT weights during training. For our experiments, we use the loss weights Lperceptual = 0.01, Lα = 0.1, Ltight = 0.1, and we train on square image crops of size 256. We train on a single A6000 GPU with a batch size of 32 for 3 days. At test time, GST can simultaneously perform 3D human pose estimation and 3D reconstruction in a single forward pass at 47fps. We verify that the network can learn to predict high-quality renderings by overfitting on a single dataset example (cf. the Appendix for more details).

#### 5. Results

In this section, we discuss the results obtained on five datasets in various evaluation settings.

##### 5.1. 3D Human Shape Results

The primary focus of this work is the ability to infer a precise 3D human body from a single image without explicit 3D supervision. We show quantitative results in Tab. 2 on RenderPeople [1] and HuMMan datasets [2]. We compute the MPJPE error with respect to the ground truth SMPL joints before and after training. The results show that without explicit 3D supervision, our training improves the quality of the pose estimation from the pretrained HMR2 [12] and TokenHMR [7]. Furthermore, Fig. 3 shows some examples of our predictions in comparison with the HMR2 initialization and the ground truth SMPL pose. Our poses appear visually to be better aligned with the ground truth, highlighting the results in Tab. 2.

We also compare our results against a fine-tuned version of HMR2 (c.f. Tab. 2). To reproduce a similar training setup to our method (that does not require any 3D ground truth annotations), we fine-tune HMR2 using only 2D keypoint annotations. We use images from all views in the dataset but restrict the supervision only to use the 2D keypoints loss. The results show that the 2D information alone is not enough for HMR2 to improve the quality of the 3D pose estimation on the two datasets, and the fine-tuned model MPJPE error is worse than the pretrained one. For completeness, we also report the errors when fine-tuning HMR2 with additional 3D annotations: 3D keypoints and ground truth SMPL parameters. We would like to emphasize that we think this is an unfair comparison to our method since our method does not use ground truth SMPL parameters or 3D keypoints for training. The MPJPE of the HMR2 version, fine-tuned with 3D data, is only 7mm better than ours on RenderPeople and 6mm better than ours on HuMMan. Figure 4 shows some examples of our predictions compared to the HMR2 models

- Table 2. Human Novel View Synthesis and 3D Keypoints Evaluation Performance Comparison. We compare GST on the RenderPeople [1] and HuMMan [2] datasets. We report PSNR, SSIM, and LPIPS for novel view synthesis and MPJPE (in mm) for 3D keypoint evaluation for each dataset. The top section methods use the Ground Truth input SMPL parameters, shown for reference, while the bottom section methods only use the single image input (our setup). ↑ means the larger is better; ↓ means the smaller is better. The best results are highlighted in bold.

RenderPeople HuMMan

Method

GT 3D Novel View 3D Shape Novel View 3D Shape Test Train PSNR↑ SSIM↑ LPIPS↓ MPJPE (mm)↓ PSNR↑ SSIM↑ LPIPS↓ MPJPE (mm)↓

NHP [25] ✓ ✓ 20.59 0.81 0.22 0.000 18.99 0.84 0.18 0.000 MPS-NeRF [9] ✓ ✓ 20.72 0.81 0.24 0.000 17.44 0.82 0.19 0.000 SHERF [15] w/ GT ✓ ✓ 22.88 0.88 0.14 0.000 20.83 0.89 0.12 0.000 HMR2 (3D fine-tuned) ✗ ✓ - - - 57.33 - - - 61.20

HMR2 [12] ✗ ✗ - - - 101.0 - - - 133.4 HMR2 (2D-only fine-tuned) ✗ ✗ - - - 127.40 - - - 163.77 TokenHMR [7] ✗ ✗ - - - 77.9 - - - 91.4 SHERF [15] w/ [12] ✗ ✗ 13.55 0.62 0.37 101.0 18.00 0.85 0.18 133.4 SHERF [15] w/ [7] ✗ ✗ 15.24 0.70 0.33 77.9 16.41 0.84 0.17 91.4 GST (Ours) ✗ ✗ 17.80 0.81 0.25 67.6 18.40 0.87 0.14 64.6

Input Image Other Views GT GST (ours)

HMR2 [12]

vs GT

vs GT

[Figure 22]

[Figure 23]

- Figure 3. 3D Shape Comparison with HMR2. 3D human body results of our GST on two subjects of HuMMan [2] dataset compared to Ground Truth SMPL parameters [29], and SMPL predictions of HMR2 [12].

finetuned on 2D and 3D data.

##### 5.2. Novel View Synthesis Results

We evaluate our method in the task of novel view synthesis across 4 datasets and compare the results with SHERF [15].

For a fair comparison with our method, which does not assume ground truth SMPL parameters are available, we evaluate SHERF using the estimated HMR2/TokenHMR pose and shape parameters instead of the ground truth ones. Our results are in Tables Tabs. 2 and 3. Visual results are

Input Image Other Views GT GST (ours)

HMR2-3D finetuning vs GT

HMR2-2D finetuning vs GT

[Figure 24]

vs GT

[Figure 25]

- Figure 4. 3D Shape Comparison with HMR2 After Fine-tuning on 2D and 3D Data. 3D human body results of our GST on two subjects of HuMMan [2] dataset compared to Ground Truth SMPL parameters [29], and SMPL predictions of HMR2 [12]. We show two versions of HMR2, one finetuned on 2D data only (HMR2-2D), and one finetuned on 3D data (HMR2-3D). Our method is only finetuned on 2D image data, but the results are almost as accurate as HMR2 finetuned on 3D data.

- Table 3. Novel View Synthesis Performance Comparison. We compare GST on the ZJU_MoCap [32] and THuman [55] datasets on novel view synthesis. The top section methods use the Ground Truth input SMPL parameters (allowing for changing the pose) and are shown for reference, while the bottom section methods only use the single image input (our setup).

ZJU MoCap THuman PSNR↑ SSIM↑ LPIPS↓ PSNR↑ SSIM↑ LPIPS↓

Method

PixelNeRF [45] - - - 16.51 0.65 0.35 NHP [25] 21.66 0.87 0.17 22.53 0.88 0.17 MPS-NeRF [9] 21.86 0.87 0.17 21.72 0.87 0.18 SHERF [15] /w GT 22.87 0.89 0.12 24.66 0.91 0.10

Splatter Img [41] 19.50 0.80 0.28 19.20 0.80 0.20 SHERF [15] /w [12] 19.11 0.81 0.21 17.27 0.85 0.16 SHERF [15] /w [7] 20.72 0.85 0.16 19.29 0.84 0.18 GST (Ours) 21.26 0.85 0.16 16.34 0.84 0.20

shown in Fig. Fig. 5. Note that the underlying 3D body is consistent, despite a slight blurriness due to the Gaussians, and follows precise 3D geometry.

To showcase the capabilities of GST on a large dataset, we train our GST on multi-view images rendered from the TH21 dataset [46], which contains 2,500 3D scans and shows the results on 200 randomly sampled test scans in Tab. 4 and Fig. 6. It clearly shows less blurriness than the other datasets. For reference, we include Splatter Image [41] in Tab. 4, where our GST predicts precise 3D body pose and shape in addition to the renderable representation, unlike

Table 4. Novel View Synthesis on Large-Scale TH21. We compare GST to fast and large-scale multi-view baseline [41] that do not need 3D annotations on the 2,500 examples from TH21 [46]. Unlike Splatter Image [41], our GST predicts precise 3D body pose and shape in addition to the renderable representation.

Method Output Novel View 3D Body PSNR↑ SSIM↑ LPIPS↓

Splatter Img [41] ✗ 23.74 0.91 0.10 GST (Ours) ✓ 22.20 0.90 0.09

Splatter Image. Predicting the human model parameters is not only useful for downstream tasks but also ensures the reconstructed shape is plausible for a human. We include additional details on the TH21 experiment and the comparison with Splatter Image in the Appendix.

##### 5.3. Ablation and analysis

Ablation Study. We present an ablation study of different design choices and key elements in our architectures and losses and their effect on the 2D and 3D results of a single image to 3D of humans on the HuMMan dataset [2] in Tab. 5. For these experiments, we report PSNR, SSIM, and LPIPS metrics computed for the entire image. It shows the importance of combining the LPIPS, tightness, and transparency loss on the final 3D precision while maintaining the visual fidelity intact. The tightness regularization of (3) has the highest impact on 3D precision, as it favors solutions

Input Image SHERF [15] w/ [12] GST (ours) GT

[Figure 26]

[Figure 27]

- Figure 5. Single Image NVS. GST on 2 subjects of HuMMan [2] dataset compared to Ground Truth renderings, and SHERF [15] (after being adapted with HMR2 to work with single image input only). GST depicts the correct human pose (compared with ground truth).

[Figure 28]

- Figure 6. Scaling Up Training of GST on TH21. We show rendering results for GST (top row) compared to Ground Truth renderings (bottom row) of each subject. The training of 2,500 subjects in TH21 [46] reduces the blurriness observed in other datasets and demonstrates the scalability merit of our GST Transformer training.

[Figure 29]

Input Image GT SMPL Our SMPL SMPL overlays

- Figure 7. Tightness Regularization. Renderings and SMPL models with (top) and without (bottom) tightness regularization. The regularization maintains a precise body shape and pose.

Table 5. Ablation study. We show an ablation study on HuMMan Dataset [2] where the left shows the design choices and the right part shows the results. For each setup, we report PSNR, SSIM, and LPIPS for novel view synthesis, as well as MPJPE (in mm) for 3D keypoints evaluation.

LPIPS loss

Tightness loss

Transparency loss

Novel View 3D Shape PSNR↑ SSIM↑ LPIPS↓ MPJPE (mm)↓

✓ ✓ 21.77 0.87 0.12 82.3

✓ ✓ 21.80 0.86 0.15 53.6 ✓ ✓ 21.77 0.87 0.12 52.3 ✓ ✓ ✓ 21.79 0.87 0.12 50.8

with much larger adjustments obtained with the Gaussian offsets. We also visualize this effect in Fig. 7. We conduct additional ablations in the Appendix, and we also report some results for 3D pose estimation from sparse views on the Human3.6M dataset [3].

#### 6. Conclusions and Discussion

In this paper, we introduced GST, a novel approach for human 3D representation that predicts 3D Gaussian Splatting [22], enabling fast rendering with accurate poses. GST leverages multi-view rendering supervision to refine the 3D joint and body predictions. This dual capability combines precise pose estimation with novel view rendering, bridging two research paradigms and showcasing the benefits of our approach. Our method could be used to reduce the friction of training a pose estimation model to deploy to any novel sports setup, without requiring any expensive pose annotations or 3D scans.

Limitations. The main limitation in our method is the requirement of multi-view datasets to train. Another issue is the slight blurriness that appears in some of the renderings, possibly as a result of the generalization limitations of the transformer when trained on relatively small datasets (in terms of subject diversity). A possible solution to this is to use a larger dataset or to pretrain on synthetic data.

in which the majority of the pose corrections are obtained with the SMPL parameters, and the Gaussians are only used for small refinements. In contrast, removing the tightness regularization encourages unrealistic and less precise poses,

Acknowledgments. This work was funded by the Podium Institute for Sports Medicine and Technology, at the University of Oxford. A.H. acknowledges the support of the KAUST Ibn Rushd Postdoc Fellowship program. J.H. acknowledges the support of the Royal Society (RG\R1\241385), Toyota Motor Europe (TME), and EPSRC (VisualAI, EP/T028572/1).

#### References

- [1] Renderpeople. In https://renderpeople.com/3dpeople, 2018. 5, 6, 13, 14, 15, 16
- [2] Zhongang Cai, Daxuan Ren, Ailing Zeng, Zhengyu Lin, Tao Yu, Wenjia Wang, Xiangyu Fan, Yang Gao, Yifan Yu, Liang Pan, Fangzhou Hong, Mingyuan Zhang, Chen Change Loy, Lei Yang, and Ziwei Liu. HuMMan: Multi-modal 4d human dataset for versatile sensing and modeling. In 17th European Conference on Computer Vision, Tel Aviv, Israel, October 23–27, 2022, Proceedings, Part VII, pages 557–577. Springer,

2022. 5, 6, 7, 8, 12, 14

- [3] Cristian Sminchisescu Catalin Ionescu, Fuxin Li. Latent structured models for human pose estimation. In Proceedings of the IEEE/CVF International Conference on Computer Vision (ICCV), 2011. 8, 12
- [4] Mingjin Chen, Junhao Chen, Xiaojun Ye, Huan ang Gao, Xiaoxue Chen, Zhaoxin Fan, and Hao Zhao. Ultraman: Single image 3d human reconstruction with ultra speed and detail.

2024. 2, 3

- [5] Junhyeong Cho, Kim Youwang, and Tae-Hyun Oh. Crossattention of disentangled modalities for 3d human mesh recovery with transformers. In Proceedings of the European Conference on Computer Vision (ECCV), 2022. 2
- [6] Alexey Dosovitskiy, Lucas Beyer, Alexander Kolesnikov, Dirk Weissenborn, Xiaohua Zhai, Thomas Unterthiner, Mostafa Dehghani, Matthias Minderer, Georg Heigold, Sylvain Gelly, Jakob Uszkoreit, and Neil Houlsby. An image is worth 16x16 words: Transformers for image recognition at scale. In International Conference on Learning Representations (ICLR), 2021. 3
- [7] Sai Kumar Dwivedi, Yu Sun, Priyanka Patel, Yao Feng, and Michael J. Black. Tokenhmr: Advancing human mesh recovery with a tokenized pose representation. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 1323–1333, 2024. 2, 5, 6, 7
- [8] Qiao Feng, Yuanwang Yang, Yu-Kun Lai, and Kun Li. R²human: Real-time 3d human appearance rendering from a single image. arXiv preprint arXiv:2312.05826, 2023. 2, 3
- [9] Xiangjun Gao, Jiaolong Yang, Jongyoo Kim, Sida Peng, Zicheng Liu, and Xin Tong. Mps-nerf: Generalizable 3d human rendering from multiview images. arXiv preprint arXiv:2203.16875, 2022. 5, 6, 7
- [10] Xiangjun Gao, Xiaoyu Li, Chaopeng Zhang, Qi Zhang, Yanpei Cao, Ying Shan, and Long Quan. Contex-human: Freeview rendering of human from a single image with textureconsistent synthesis, 2023. 2, 3
- [11] Georgios Georgakis, Ren Li, Srikrishna Karanam, Terrence Chen, Jana Košecká, and Ziyan Wu. Hierarchical kinematic

human mesh recovery. In ECCV, 2020. 2

- [12] Shubham Goel, Georgios Pavlakos, Jathushan Rajasegaran, Angjoo Kanazawa*, and Jitendra Malik*. Humans in 4D: Reconstructing and tracking humans with transformers. In International Conference on Computer Vision (ICCV), 2023. 1, 2, 3, 4, 5, 6, 7, 8, 12, 13, 14, 15
- [13] Riza Alp Guler and Iasonas Kokkinos. Holopose: Holistic 3d human reconstruction in-the-wild. In CVPR, 2019. 2
- [14] Hsuan-I Ho, Jie Song, and Otmar Hilliges. Sith: Single-view textured human reconstruction with image-conditioned diffusion. In Proceedings of the IEEE Conference on Computer Vision and Pattern Recognition (CVPR), 2024. 2, 3
- [15] Shoukang Hu, Fangzhou Hong, Liang Pan, Haiyi Mei, Lei Yang, and Ziwei Liu. Sherf: Generalizable human nerf from a single image. In Proceedings of the IEEE/CVF International Conference on Computer Vision (ICCV), 2023. 2, 3, 5, 6, 7, 8, 13, 14
- [16] Shoukang Hu, Tao Hu, and Ziwei Liu. Gauhuman: Articulated gaussian splatting from monocular human videos. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 20418–20431,

2024. 3

- [17] Yangyi Huang, Hongwei Yi, Weiyang Liu, Haofan Wang, Boxi Wu, Wenxiao Wang, Binbin Lin, Debing Zhang, and Deng Cai. One-shot implicit animatable avatars with modelbased priors. In IEEE Conference on Computer Vision (ICCV),

2023. 3

- [18] Yangyi Huang, Hongwei Yi, Yuliang Xiu, Tingting Liao, Jiaxiang Tang, Deng Cai, and Justus Thies. TeCH: Text-guided Reconstruction of Lifelike Clothed Humans. In International Conference on 3D Vision (3DV), 2024. 3
- [19] Christian Keilstrup Ingwersen, Christian Mikkelstrup, Janus Nørtoft Jensen, Morten Rieger Hannemose, and Anders Bjorholm Dahl. Sportspose: A dynamic 3d sports pose dataset. In Proceedings of the IEEE/CVF International Workshop on Computer Vision in Sports, 2023. 5
- [20] Hanbyul Joo, Hao Liu, Lei Tan, Lin Gui, Bart Nabbe, Iain Matthews, Takeo Kanade, Shohei Nobuhara, and Yaser Sheikh. Panoptic studio: A massively multiview system for social motion capture. In Proc. of International Conference on Computer Vision (ICCV), pages 3334–3342, 2015. 1, 13
- [21] Angjoo Kanazawa, Michael J Black, David W Jacobs, and Jitendra Malik. End-to-end recovery of human shape and pose. In CVPR, 2018. 2, 5
- [22] Bernhard Kerbl, Georgios Kopanas, Thomas Leimkühler, and George Drettakis. 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics, 42(4), 2023. 2, 3, 4, 8
- [23] Muhammed Kocabas, Chun-Hao P Huang, Otmar Hilliges, and Michael J Black. Pare: Part attention regressor for 3d human body estimation. In ICCV, 2021. 2
- [24] Nikos Kolotouros, Georgios Pavlakos, and Kostas Daniilidis. Convolutional mesh regression for single-image human shape reconstruction. In CVPR, 2019. 2
- [25] Youngjoong Kwon, Dahun Kim, Duygu Ceylan, and Henry Fuchs. Neural human performer: Learning generalizable radiance fields for human performance rendering. Advances in Neural Information Processing Systems, 34:24741–24752,

2021. 5, 6, 7

- [26] Kevin Lin, Lijuan Wang, and Zicheng Liu. End-to-end human pose and mesh reconstruction with transformers. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2021. 2
- [27] Kevin Lin, Lijuan Wang, and Zicheng Liu. Mesh graphormer. In Proceedings of the IEEE/CVF International Conference on Computer Vision (ICCV), 2021. 2
- [28] Tsung-Yi Lin, Michael Maire, Serge J. Belongie, Lubomir D. Bourdev, Ross B. Girshick, James Hays, Pietro Perona, Deva Ramanan, Piotr Dollár, and C. Lawrence Zitnick. Microsoft COCO: common objects in context. CoRR, abs/1405.0312,

2014. 12

- [29] Matthew Loper, Naureen Mahmood, Javier Romero, Gerard Pons-Moll, and Michael J Black. Smpl: A skinned multiperson linear model. ACM Transactions on Graphics (TOG), 34(6):1–16, 2015. 1, 2, 4, 6, 7, 14, 15
- [30] OpenAI. Gpt-4 technical report, 2023. 3
- [31] Panwang Pan, Zhuo Su, Chenguo Lin, Zhen Fan, Yongjie Zhang, Zeming Li, Tingting Shen, Yadong Mu, and Yebin Liu. Humansplat: Generalizable single-image human gaussian splatting with structure priors. arXiv preprint arXiv:2406.12459, 2024. 3
- [32] Sida Peng, Yuanqing Zhang, Yinghao Xu, Qianqian Wang, Qing Shuai, Hujun Bao, and Xiaowei Zhou. Neural body: Implicit neural representations with structured latent codes for novel view synthesis of dynamic humans. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 9054–9063, 2021. 5, 7, 14
- [33] Marco Pesavento, Yuanlu Xu, Nikolaos Sarafianos, Robert Maier, Ziyan Wang, Chun-Han Yao, Marco Volino, Edmond Boyer, Adrian Hilton, and Tony Tung. Anim: Accurate neural implicit model for human reconstruction from a single rgb-d image, 2024. 3
- [34] Alec Radford, Jong Wook Kim, Chris Hallacy, Aditya Ramesh, Gabriel Goh, Sandhini Agarwal, Girish Sastry, Amanda Askell, Pamela Mishkin, Jack Clark, et al. Learning transferable visual models from natural language supervision. In Proceedings of the International Conference on Machine Learning (ICML), pages 8748–8763. PMLR, 2021. 3
- [35] Aditya Ramesh, Mikhail Pavlov, Gabriel Goh, Scott Gray, Chelsea Voss, Alec Radford, Mark Chen, and Ilya Sutskever. Zero-shot text-to-image generation. In Proceedings of the International Conference on Machine Learning (ICML), pages 8821–8831. PMLR, 2021. 3
- [36] Aditya Ramesh, Prafulla Dhariwal, Alex Nichol, Casey Chu, and Mark Chen. Hierarchical text-conditional image generation with clip latents. arXiv preprint arXiv:2204.06125, 2022.
- [37] Robin Rombach, Andreas Blattmann, Dominik Lorenz, Patrick Esser, and Björn Ommer. High-resolution image synthesis with latent diffusion models. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 10684–10695, 2022.
- [38] Chitwan Saharia, William Chan, Saurabh Saxena, Lala Li, Jay Whang, Emily L Denton, Kamyar Ghasemipour, Raphael Gontijo Lopes, Burcu Karagol Ayan, Tim Salimans, et al. Photorealistic text-to-image diffusion models with deep language

- understanding. Advances in Neural Information Processing Systems (NeurIPS), 35:36479–36494, 2022. 3
- [39] Shunsuke Saito, Zeng Huang, Ryota Natsume, Shigeo Morishima, Angjoo Kanazawa, and Hao Li. Pifu: Pixel-aligned implicit function for high-resolution clothed human digitization. In Proceedings of the IEEE/CVF international conference on computer vision, pages 2304–2314, 2019. 2, 3
- [40] Shih-Yang Su, Frank Yu, Michael Zollhöfer, and Helge Rhodin. A-nerf: Articulated neural radiance fields for learning human shape, appearance, and pose. In Advances in Neural Information Processing Systems (NeurIPS), 2021. 3
- [41] Stanislaw Szymanowicz, Christian Rupprecht, and Andrea Vedaldi. Splatter image: Ultra-fast single-view 3d reconstruction. Conference on Computer Vision and Pattern Recognition (CVPR), 2024. 2, 4, 5, 7, 12, 13
- [42] Ashish Vaswani, Noam Shazeer, Niki Parmar, Jakob Uszkoreit, Llion Jones, Aidan N Gomez, Łukasz Kaiser, and Illia Polosukhin. Attention is all you need. In Advances in Neural Information Processing Systems (NeurIPS), 2017. 4
- [43] Zhenzhen Weng, Jingyuan Liu, Hao Tan, Zhan Xu, Yang Zhou, Serena Yeung-Levy, and Jimei Yang. Template-free single-view 3d human digitalization with diffusion-guided lrm. Preprint, 2023. 2, 3
- [44] Yuxuan Xue, Xianghui Xie, Riccardo Marin, and Gerard Pons-Moll. Human 3diffusion: Realistic avatar creation via explicit 3d consistent diffusion models. Arxiv, 2024. 3
- [45] Alex Yu, Vickie Ye, Matthew Tancik, and Angjoo Kanazawa. pixelnerf: Neural radiance fields from one or few images. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 4578–4587,

2021. 7

- [46] Tao Yu, Zerong Zheng, Kaiwen Guo, Pengpeng Liu, Qionghai Dai, and Yebin Liu. Function4d: Real-time human volumetric capture from very sparse consumer rgbd sensors. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2021. 5, 7, 8, 12, 13, 16
- [47] Ye Yuan, Xueting Li, Yangyi Huang, Shalini De Mello, Koki Nagano, Jan Kautz, and Umar Iqbal. Gavatar: Animatable 3d gaussian avatars with implicit mesh learning. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 896–905, 2024. 3
- [48] Xiaoyu Zhan, Jianxin Yang, Yuanqi Li, Jie Guo, Yanwen Guo, and Wenping Wang. Semantic human mesh reconstruction with textures. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2024. 2, 3
- [49] Hongwen Zhang, Yating Tian, Xinchi Zhou, Wanli Ouyang, Yebin Liu, Limin Wang, and Zhenan Sun. Pymaf: 3d human pose and shape regression with pyramidal mesh alignment feedback loop. In ICCV, 2021. 2
- [50] Hongwen Zhang, Yating Tian, Yuxiang Zhang, Mengcheng Li, Liang An, Zhenan Sun, and Yebin Liu. Pymaf-x: Towards well-aligned full-body model regression from monocular images. PAMI, 2023. 2
- [51] Kai Zhang, Sai Bi, Hao Tan, Yuanbo Xiangli, Nanxuan Zhao, Kalyan Sunkavalli, and Zexiang Xu. Gs-lrm: Large reconstruction model for 3d gaussian splatting. arXiv, 2024. 4

- [52] Richard Zhang, Phillip Isola, Alexei A Efros, Eli Shechtman, and Oliver Wang. The unreasonable effectiveness of deep features as a perceptual metric. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2018. 4, 5
- [53] Zechuan Zhang, Li Sun, Zongxin Yang, Ling Chen, and Yi Yang. Global-correlated 3d-decoupling transformer for clothed avatar reconstruction. In Advances in Neural Information Processing Systems (NeurIPS), 2023. 2, 3
- [54] Zechuan Zhang, Zongxin Yang, and Yi Yang. Sifu: Side-view conditioned implicit function for real-world usable clothed human reconstruction. 2024. 2, 3
- [55] Zerong Zheng, Tao Yu, Yixuan Wei, Qionghai Dai, and Yebin Liu. Deephuman: 3d human reconstruction from a single image. In Proceedings of the IEEE/CVF International Conference on Computer Vision, pages 7739–7749, 2019. 5, 7, 13, 16

## GST: Precise 3D Human Body from a Single Image with Gaussian Splatting Transformers

### Supplementary Materials

#### A. Additional Results and Analysis

##### A.1. Additional Ablations

In addition to the ablations described in Table 5 in the main paper, we report here three variations to the GST model that did not result in a performance improvement. The ablations are provided in Table I.

More Gaussians. The first design change we tested is an increase in the number of Gaussians per vertex. We increase the number of splats by predicting two or three independent offsets per vertex. Because random initialization breaks the symmetry, the model can learn to move each splat independently even though all two/three are anchored to the same vertex. Contrary to our assumption, an increase in the number of splats did not result in a increased visual quality of the renderings.

Setting Opacity to 1. Predicting opacity is not strictly necessary to render humans, therefore we tried simplifying the model by removing this parameter. We removed the opacity prediction during training and manually set the opacity to 1 for all the Gaussians.

Single-view + Multi-view Images. Next, to increase the subject diversity in the small datasets we use, we tried including some single view images in our training pipeline. For this experiment, we use crops of images containing humans from the MSCOCO dataset [28]. The single view images are used for training together with the multi-view images from the original dataset. For the single view images, the model predictions are supervised using the same input image. The results do not show any notable improvement.

##### A.2. Overfitting Example

To test that the number of Gaussians is sufficient to produce sharp details, we train our model to overfit a single data sample. We obtain an almost perfect reconstruction with PSNR of 41. Fig. I shows examples of the renderings we obtained. This result confirms our assumption that with a large enough dataset, our model would be able to learn sharper details than it currently learns on the small scale datasets.

Table I. Additional Negative Ablations. For completeness, we show additional ablations on HuMMan Dataset [2] that did not give positive improvements to our best setup of Table 5 in the main paper. For each setup, we report PSNR, SSIM, and LPIPS for novel view synthesis, as well as MPJPE (in mm) for 3D keypoints evaluation.

Ablation setup Novel View 3D Shape

PSNR↑ SSIM↑ LPIPS↓ MPJPE (mm)↓ our best model 21.79 0.87 0.12 50.8

- 2 Gaussians per vertex 21.25 0.87 0.12 50.1
- 3 Gaussians per vertex 21.18 0.87 0.12 53.2 setting opacity to 1 21.17 0.87 0.11 58.4

single-view + multi-view 21.47 0.87 0.12 53.4

##### A.3. Additional Details for TH21 Experiment

For the TH21 [46] experiment in Table 4 in the main report, we use 72 views rendered in a loop around the subject. We train both our method and Splatter Image [41] using 256x256 images. Despite our model performing worse than Splatter Image in terms of visual metrics, our model also predicts the SMPL paramters for 3D pose estimation. This is both useful for downstream tasks, but also ensures that the underlying 3D shape is plausible for a human. This difference can be noticed in the examples in Fig. II, where GST can reconstruct a plausible human shape despite the uncommon input pose, while Splatter Image fails to reconstruct arms and legs.

##### A.4. 3D Pose Estimation from Sparse Views

We train GST on the common 3D pose estimation dataset Human3.6M [3] using the default split for train and test subjects (subjects 9 and 11 are used for testing). This dataset is not ideal for our method as it only has 4 views and very few subjects, therefore it’s difficult to generalize to unseen poses and subjects. Additionally, the human masks provided with the dataset are not always precise and our method tends to model parts of the background together with the human. This affects the visual results and the 3D pose estimation. The visual metrics for our GST are evaluated on a squared crop of size 256x256 around the human with a PSNR of 18.68 and a 3D error of MPJPE ↓ = 63.7 mm compared to 50.0 mm for HMR2 [12].

[Figure 30]

Renderings

Ground truth

- Figure I. Overfitting to a single sample. Ground truth (top) and renderings (bottom) of our model results when overfitting to a single data sample.

[Figure 31]

[Figure 32]

Splatter Image

GST (ours)

Ground truth

- Figure II. Splatter Image comparison. Side view comparison with Splatter Image [41] on TH21 [46] for unusual input poses. Input image on the left, Splatter Image rendering in the first row, GST renderings in the second row.

[Figure 33]

Input Image Other Views HMR2 [12] GST (ours) Input Image Other Views HMR2 [12] GST (ours)

- Figure III. Example of human pose improvements using our method GST. 3D human body results of our GST and SMPL predictions of HMR2 [12] on a sports sequence from the CMU panoptic dome dataset [20].

#### B. Additional Visualizations

Fig. III shows additional pose estimation results on the sports sequence of the CMU Panoptic dataset [20]. Fig. IV shows additional examples of novel view synthesis comparisons

with SHERF [15]. Fig. V and VI show additional pose comparisons for the RenderPeople [1] dataset. Fig. VII and VIII show examples of novel view synthesis results for the TH21 [46], THuman [55] and RenderPeople [1] datasets.

Input Image SHERF [15] w/ [12] Renderings GST (ours) Renderings GT Renderings

[Figure 34]

[Figure 35]

[Figure 36]

[Figure 37]

- Figure IV. Single Image NVS on two subjects of Zju-Mocap [32] and two subjects of HuMMan [2] compared to SHERF [15] (after being adapted with HMR2 to work with single image input only). GST shows improved visual quality, especially when comparing the depicted pose to ground truth.

[Figure 38]

[Figure 39]

Input Image Other Views GT GST (ours)

vs GT

HMR2 [12]

vs GT

- Figure V. 3D Shape Comparison with HMR2. 3D human body results of our GST on two subjects of RenderPeople [1] dataset compared to Ground Truth SMPL parameters [29], and SMPL predictions of HMR2 [12].

Input Image Other Views GT GST (ours)

HMR2-3D finetuning vs GT

HMR2-2D finetuning vs GT

vs GT

[Figure 40]

[Figure 41]

[Figure 42]

[Figure 43]

[Figure 44]

- Figure VI. 3D Shape Comparison with HMR2 After Fine-tuning on 2D and 3D Data. 3D human body results of our GST on five subjects of RenderPeople [1] dataset compared to Ground Truth SMPL parameters [29], and SMPL predictions of HMR2 [12]. We show two versions of HMR2, one finetuned on 2D data only (HMR2-2D), and one finetuned on 3D data (HMR2-3D). Our method is only finetuned on 2D image data, but the results are almost as accurate as HMR2 finetuned on 3D data.

[Figure 45]

[Figure 46]

[Figure 47]

###### Figure VII. Results in TH21 [46]. Rendering results for GST (top row) compared to Ground Truth renderings (bottom row) of each subject. An example of loose clothes is in the last row.

[Figure 48]

[Figure 49]

###### Figure VIII. Visualization of Single Image Novel View Synthesis Results on THuman and RenderPeople. We show single image novel view synthesis results on one subject of THuman [55] dataset and one subjects of RenderPeople [1] dataset of our GST (top row) compared to Ground Truth renderings (bottom row) of each subject.

