## GS-LRM: Large Reconstruction Model for 3D Gaussian Splatting

# arXiv:2404.19702v1[cs.CV]30Apr2024

Kai Zhang∗1 Sai Bi∗1 Hao Tan∗1 Yuanbo Xiangli2 Nanxuan Zhao1 Kalyan Sunkavalli1 Zexiang Xu1

1Adobe Research 2Cornell University

Abstract. We propose GS-LRM, a scalable large reconstruction model that can predict high-quality 3D Gaussian primitives from 2-4 posed sparse images in ∼0.23 seconds on single A100 GPU. Our model features a very simple transformer-based architecture; we patchify input posed images, pass the concatenated multi-view image tokens through a sequence of transformer blocks, and decode final per-pixel Gaussian parameters directly from these tokens for differentiable rendering. In contrast to previous LRMs that can only reconstruct objects, by predicting per-pixel Gaussians, GS-LRM naturally handles scenes with large variations in scale and complexity. We show that our model can work on both object and scene captures by training it on Objaverse and RealEstate10K respectively. In both scenarios, the models outperform state-of-the-art baselines by a wide margin. We also demonstrate applications of our model in downstream 3D generation tasks. Our project webpage is available at: https://sai-bi.github.io/project/gs-lrm/.

Keywords: Large Reconstruction Models · 3D Reconstruction · Gaussian Splatting

### 1 Introduction

Reconstructing a 3D scene from image captures is both a central problem and a long-standing challenge in computer vision. Traditionally, high-quality 3D reconstruction relies on complex photogrammetry systems [23,50,52] and requires a dense set of multi-view images. Recent advancements in neural representations and differentiable rendering [9, 30, 41, 42] have shown superior reconstruction and rendering quality, by optimizing renderings on a per-scene basis. However, these methods are slow and still require a large number of input views. Recently, transformer-based 3D large reconstruction models (LRMs) have been proposed, learning general 3D reconstruction priors from vast collections of 3D objects and achieving sparse-view 3D reconstruction of unprecedented quality [27,32,63,68]. However, these models adopt triplane NeRF [7,44] as the scene representation, which suffers from a limited triplane resolution and expensive volume rendering. This leads to challenges in training and rendering speeds, preserving fine details, and scaling to large scenes beyond object-centric inputs.

* Equal contribution.

[Figure 1]

[Figure 2]

[Figure 3]

[Figure 4]

[Figure 5]

| |
|---|

| |
|---|

[Figure 6]

[Figure 7]

[Figure 8]

[Figure 9]

[Figure 10]

[Figure 11]

[Figure 12]

Prompt: a plush toy of a corgi nurse Our rendered novel views Our rendered novel views

Input images

[Figure 13]

[Figure 14]

Rendered novel view

Rendered novel view

[Figure 15]

[Figure 16]

[Figure 17]

[Figure 18]

[Figure 19]

[Figure 20]

Input images Novel view depth

Input images Novel view depth

- Fig. 1: Novel-view renderings of our predicted Gaussians from object captures (top left), text-conditioned generated object images (top right), scene captures (bottom left) and text-conditioned generated scene images (bottom right, from Sora [43] with the prompt “Tour of an art gallery with many beautiful works of art in different styles” ). The rendered depth for scenes is at the bottom. By predicting 3D Gaussians with

- our transformer-based GS-LRM, we can naturally handle objects and complex scenes.

Our goal is to build a general, scalable, and efficient 3D reconstruction model. To this end, we propose GS-LRM, a novel transformer-based large reconstruction model that predicts 3D Gaussian primitives [30] from sparse input images, enabling fast and high-quality rendering and reconstruction for both objects and scenes, as depicted in Fig. 1. The core of our approach is a simple and scalable transformer-based network architecture that predicts per-pixel Gaussians. Specifically, we patchify input posed images into patch tokens and process them through a series of transformer blocks comprising self-attention and MLP layers, and directly regress per-view per-pixel 3D Gaussian primitives from the contextualized multi-view tokens. Unlike previous LRMs that require careful designs of additional (triplane) NeRF tokens for reconstruction, we align input (2D images) and output (3D Gaussians) in the same pixel space, predicting one Gaussian per pixel along the ray. This alignment not only simplifies the transformer architecture but also facilitates 3D Gaussians to preserve the high-frequency details in the input images. Moreover, predicting per-pixel Gaussians allows our model to freely adapt to the input image resolution, exhibiting accurate scene details in

high-resolution inputs, that previous LRMs with a fixed triplane resolution often struggle with.

Our transformer-based GS-LRM is highly scalable from multiple aspects, including model sizes, training data, and scene scales. We train two versions of our GS-LRM on two large-scale datasets including Objaverse [19] and RealEstate10K [76], separately for object and scene reconstruction tasks, using the same transformer architecture with minimal domain-specific parameter changes. The results demonstrate that our GS-LRM (with 300M model parameters, up to 16K transformer token length) achieves high-quality sparse-view reconstruction for both object and scene scenarios. We also achieve state-of-the-art reconstruction quality and outperform previous methods by a large margin of 4dB PSNR for objects and 2.2dB PSNR for scenes.

### 2 Related Work

Multi-view 3D Reconstruction. 3D reconstruction has been extensively studied in computer vision and graphics for decades. To address this task, various traditional methods have been proposed, including structure-from-motion (SfM) [1, 48, 50, 56] for sparse reconstruction and calibration, and multi-view stereo (MVS) [23,47,52] for dense reconstruction. Recently, deep learning-based MVS methods have also been proposed [16,25,53,69,70], offering efficient highquality reconstruction in a feed-forward manner. Generally, these methods utilize

##### 3D cost volumes — constructed by unprojecting 2D image features into plane sweeps — to achieve high-quality per-view depth estimation. In this work, we estimate pixel-aligned 3D Gaussian primitives, essentially achieving a per-pixel estimation of depth along with additional Gaussian properties. Instead of relying on 3D cost volumes, we adopt a multi-view transformer to directly regress Gaussians, using self-attention over all multi-view image patches, naturally allowing for multi-view correspondence reasoning. Our transformer model can effectively handle highly sparse input views, a big challenge for cost volume-based methods.

Radiance Field Reconstruction. Recently, a vast number of works have emerged to address scene reconstruction by optimizing radiance field representations [41] with differentiable rendering, bypassing traditional MVS pipelines. While NeRF [41] initially represents a radiance field as a coordinate-based MLP, this area has expanded with various models, including voxel-based [34, 59, 72], factorization-based [7, 9–11], hash grid-based [42], and point- (or primitive-) based [24,30,35,67] representations among others [4–6,74]. We leverage Gaussian Splatting [30], a state-of-the-art technique for radiance field modeling and rendering, allowing us to achieve real-time rendering and large-scale scene reconstruction. In contrast to these radiance field models optimized on a per-scene basis given dense images, we propose a generalizable model trained across scenes for feed-forward sparse-view reconstruction.

Feed-forward Reconstruction. Prior works have proposed various feed-forward 3D reconstruction and rendering methods. Early efforts adopt CNNs to estimate neural points [2,66,71] or multi-plane images (MPIs) [33,39,76], achieving

rendering via point splatting or alpha compositing. We utilize Gaussian Splatting, which can be seen as a generalization of point splatting and MPI compositing. Recently, generalizable radiance field-based methods have been proposed and achieved state-of-the-art quality [12, 58, 64, 72], leveraging NeRF-like volume rendering. These methods typically leverage 3D-to-2D geometric projection to sample per-view 2D features for 3D reconstruction, using model designs like epipolar lines [57,58,64] or plane-swept cost-volumes [12,29,36] similar to MVS. We instead leverage a clean large transformer model without such 3D inductive bias, and directly regress per-view pixel-aligned 3D Gaussian primitives. The dense self-attention layers in our model can effectively learn multi-view correspondence and general reconstruction priors, leading to significantly better rendering quality than previous epipolar-based methods (see Tab. 1).

Our model is inspired by the recent transformer-based 3D large reconstruction models (LRMs) [27,32,63,68], which are based on triplane NeRF and focus on objects. We propose a novel LRM for Gaussian Splatting with a simplified network architecture and per-pixel Gaussian prediction mechanism, achieving better quality, faster rendering, and scaling up to handle large scenes.

PixelSplat [8] and LGM [61] are two concurrent works that are also based on pixel-aligned 3D Gaussian prediction. In particular, LGM leverages a U-Net architecture and only focuses on object generation; PixelSplat leverages epipolar line-based sampling and only tackles scene-level reconstruction. In contrast, our GS-LRM is a clean transformer model that is much simpler to implement and scale. We demonstrate that our model significantly outperform these two concurrent works in terms of both object and scene-level reconstructions.

### 3 Method

In this section, we present the technical details of our method, including the architecture of our transformer-based model (Sec. 3.1) and the loss functions (Sec. 3.2).

#### 3.1 Transformer-based Model Architecture

As shown in Fig. 2, we train a transformer model to regress per-pixel 3D GS parameters from a set of images with known camera poses. We tokenize posed input images via a patchify operator [20]. Multi-view image tokens are then concatenated and passed through a sequence of transformer blocks consisting of self-attention and MLP layers. From each output token, we decode the attributes of pixel-aligned Gaussians in the corresponding patch with a linear layer.

Tokenizing posed images. The inputs to our model are N multi-view images {Ii ∈ RH×W×3|i = 1,2,..,N} and their camera intrinsic and extrinsic parameters; here H and W are the height and width of the images. Following prior works [13,68], we use the Plücker ray coordinates [45] of each image {Pi ∈ RH×W×6} computed from the camera parameters for pose conditioning. Specifically, we concatenate the image RGBs and their Plücker coordinates

[Figure 21]

[Figure 22]

| |
|---|

[Figure 23]

[Figure 24]

Linear & Unpatchify

Patchify & Linear

Self-Att

MLP

+

+

[Figure 25]

| |
|---|

[Figure 26]

[Figure 27]

Transformer Block (×𝐿)

Image + Plücker rays

Per-pixel Gaussians

Merged Gaussians

- Fig. 2: Our simple transformer-based GS-LRM predicts 3D Gaussian parameters from sparse posed images. Images are patchified and the concatenated patch tokens are sent to the transformer blocks. By unpatchifying the transformer’s output, each pixel is unprojected to a 3D Gaussian. The final output merges all 3D Gaussians. (Note that here we visualize the Gaussian centers and colors as point clouds for illustration; please refer to in Fig. 1 for the splatting-based renderings.)

channel-wise, enabling per-pixel pose conditioning and forming a per-view feature map with 9 channels. Similar to ViT [20], we patchify the inputs by dividing the per-view feature map into non-overlapping patches with a patch size of p. For each 2D patch, we flatten it into a 1D vector with a length of p2 · 9. Finally, we adopt a linear layer that maps the 1D vectors to image patch tokens of d dimensions, where d is the transformer width. Formally, this process can be written as:

{Tij}j=1,2,...,HW/p2 = Linear Patchifyp Concat(Ii,Pi) , (1)

where {Tij ∈ Rd} denotes the set of patch tokens for image i, and there are a total number of HW/p2 such tokens (indexed by j) for each image. As Plücker coordinates vary across pixels and views, they naturally serve as spatial embeddings to distinguish different patches; hence we do not use additional positional embedding as in [20] or view embeddings [63].

Processing image tokens with transformer. Given the set of multi-view image tokens {Tij}, we concatenate and feed them through a chain of transformer blocks [62]:

{Tij}0 = {Tij}, (2) {Tij}l = TransformerBlockl({Tij}l−1),l = 1,2,...,L, (3)

where L is the total number of transformer blocks. Each transformer block is equipped with residual connections [26] (i.e., the operator ‘+’ in Fig. 2) and consists of Pre-LayerNorm [3], multi-head Self-Attention [62] and MLP.

Decoding output tokens to per-pixel Gaussians. With the output tokens {Tij}L from the transformer, we decode them into Gaussian parameters using a single linear layer:

{Gij} = Linear({Tij}L), (4)

2·q represents the 3D Gaussian and q is the number of parameters per Gaussian. We then unpatchify Gij into p2 Gaussians. Since we use the same patch size p for patchifying and unpatchifying operations, we end up with HW Gaussians for each view where each 2D pixel corresponds to one 3D Gaussian.

where Gij ∈ Rp

Similar to [30], the 3D Gaussian is parameterized by 3-channel RGB, 3channel scale, 4-channel rotation quaternion, 1-channel opacity, and 1-channel ray distance. Thus q=12 in our formulation. For splatting rendering, the location of the Gaussian center is obtained by the ray distance and the known camera parameters. Specifically, suppose that t, rayo, rayd are the ray distance, ray origin, and ray direction, respectively, the Gaussian center xyz = rayo + t · rayd. We will discuss the detailed initialization of these parameters in the Appendix.

The final output of our model is simply the merge of 3D Gaussians from all N input views. Thus the model will output N · HW Gaussians in total. It’s worth noting that the number of Gaussians scale up with increased input resolution, which is in contrast to the fixed-resolution triplane used in prior LRM works [27, 32, 63, 68]. This property allows us to better handle high-frequency details in the inputs and large-scale scene captures.

#### 3.2 Loss Functions

During training, we render the images at the M supervision views using the predicted Gaussian splats, and minimize the image reconstruction loss. Let {I∗i′|i′ = 1,2,...,M} be the set of groundtruth views, and {ˆI∗i′} be the rendered images, our loss function is a combination of MSE (Mean Squared Error) loss and Perceptual loss:

M

1 M

L =

i′=1

MSE ˆI∗i′,I∗i′ + λ · Perceptual ˆI∗i′,I∗i′ , (5)

where λ is the weight of the perceptual loss. We empirically find that the perceptual loss in [14] based on VGG-19 network [55] provides a more stable training than LPIPS [75] used in [27,32,63,68], and we use it in this work.

### 4 Experiments

In this section, we first describe the training and testing datasets (Sec. 4.1), then introduce the implementation and training details (Sec. 4.2). We make both quantitative and qualitative comparisons (Sec. 4.3) against different baselines. Finally we show some downstream applications (Sec. 4.5) of our method. We refer the readers to our project page for video results and interactive visualizations.

#### 4.1 Datasets

Table 1: Comparison against baselines on object-level (left) and scene-level (right) reconstructions. We matched the baseline settings by comparing with Instant3D’s Triplane-LRM [32] and LGM [61] at 512 and 256 resolution respectively for both input and rendering. All scene-level results were performed at 256 resolution for fair comparisons. We outperform relevant baselines by a large margin in both scenarios.

GSO ABO PSNR ↑ SSIM ↑ LPIPS ↓ PSNR ↑ SSIM ↑ LPIPS ↓ Triplane-LRM [32] 26.54 0.893 0.064 27.50 0.896 0.093

Ours (Res-512) 30.52 0.952 0.050 29.09 0.925 0.085 LGM [61] 21.44 0.832 0.122 20.79 0.813 0.158 Ours (Res-256) 29.59 0.944 0.051 28.98 0.926 0.074

RealEstate10k PSNR ↑ SSIM ↑ LPIPS ↓ pixelNeRF [72] 20.43 0.589 0.550

GPNR [57] 24.11 0.793 0.255 Du et. al [22] 24.78 0.820 0.213 pixelSplat [8] 25.89 0.858 0.142

Ours 28.10 0.892 0.114

Object-level dataset. We use the Objaverse dataset [19] to train our objectlevel reconstruction model. We only leverage the multi-view renderings of the objects without accessing explicit 3D information (such as depths). Following [27], we center and scale each 3D object to a bounding box of [−1,1]3, and render 32 views randomly placed around the object with a random distance in the range of [1.5,2.8]. Each image is rendered at a resolution of 512 × 512 under uniform lighting. We render a total of 730K objects. We evaluate our model on two 3D object datasets including the full Google Scanned Objects (GSO) [21] that contains 1009 objects and the Amazon Berkeley Objects (ABO) [17] dataset from which we sample 1000 objects. We follow Instant3D [32] and render 4 structured input views evenly placed around the objects with an elevation of 20◦ to ensure a good coverage, and randomly select another 10 views for testing.

Scene-level dataset. We use the RealEstate10K [76] dataset to train our scenelevel model. It sources from real estate video footages and has both indoor and outdoor scenes. The dataset contains 80K video clips curated from 10K YouTube videos. Each clip has a set of extracted frames with known camera poses estimated by SfM [51]. We follow the standard training/testing split for the dataset, which is also used in pixelSplat [8].

#### 4.2 Implementation Details

We have two models trained independently in this paper: object-level GS-LRM and scene-level GS-LRM. The two models share the same model architecture and take almost the same training recipe. The differences are in the training data (Sec. 4.1) and view selection and normalization (see details below). We also made necessary changes for fair comparisons with baseline methods (Sec. 4.3).

Model details. We use a patch size of 8 × 8 for the image tokenizer. Our transformer consists of 24 layers, and the hidden dimension of the transformer is 1024. Each transformer block consists of a multi-head self-attention layer with 16 heads, and a two-layered MLP with GeLU activation. The hidden dimension of the MLP is 4096. Both layers are equipped with Pre-Layer Normalization

[Figure 28]

[Figure 29]

[Figure 30]

|[Figure 31]<br><br>[Figure 32]<br><br>[Figure 33]<br><br>[Figure 34]|
|---|

[Figure 35]

[Figure 36]

[Figure 37]

|[Figure 38]<br><br>[Figure 39]<br><br>[Figure 40]<br><br>[Figure 41]|
|---|

25.18 30.73 23.92 30.83

[Figure 42]

[Figure 43]

[Figure 44]

[Figure 45]

[Figure 46]

[Figure 47]

|[Figure 48]<br><br>[Figure 49]<br><br>[Figure 50]<br><br>[Figure 51]|
|---|

|[Figure 52]<br><br>[Figure 53]<br><br>[Figure 54]<br><br>[Figure 55]|
|---|

24.02 27.28 17.73 25.08 Input images Ground truth Triplane-LRM Ours Ground truth Triplane-LRM Ours

- Fig. 3: Visual comparisons to Instant3D’s Triplane-LRM [32]. The 4-view input images are shown in the leftmost column, and we compare novel view renderings on the right. The Triplane-LRM cannot reconstruct high-frequency details (top left and top right) and thin structures (bottom left) well. It also suffers from texture distortion artifacts (bottom right), possibly due to a lack of representation capability and the non-pixelaligned prediction of triplanes. In contrast, our GS-LRM works significantly better in these cases. PSNRs are shown under each image.

(LN) and residual connections. Besides the above Pre-LNs, Layer Normalization is used after the patchifying Linear layer and before the unpatchifying Linear layer to stabilize the training.

Training details. To enable efficient training and inference, we adopt FlashAttention-v2 [18] in the xFormers [31] library, gradient checkpointing [15], and mixed-precision training [38] with BF16 data type. We also apply deferred backpropagation [73] for rendering the GS to save GPU memory. We pre-train the model with a resolution of 256 × 256 and fine-tune the trained model with a resolution of 512 × 512 for a few epochs. The fine-tuning shares the same model architecture and initializes the model with the pre-trained weights, but processes more tokens than the pre-training. At each training step, for object-level, we sample a set of 8 images (from 32 renderings) as a data point, and from which we randomly select 4 input views and 4 supervision views independently. This sampling strategy encourages more overlap between input views and rendering views than directly sampling from 32 rendering views, which helps the model’s convergence. For scene-level, we adopt two input views for a fair comparison with pixelSplat [8]. Following pixelSplat [8], we select 2 random input views and then randomly sample supervision views between them; we use 6 supervision views for each batch. We normalize the camera poses for scene-level input images following common practices in previous forward-facing reconstructions as done in [9,40]. We further fine-tune a model that takes 2 − 4 input images of 512 × 512 for generating visual results. For both models, we use 64 A100 (40G VRAM) GPUs to train our models; 256-res pretraining takes 2 days, while 512-res finetuning takes 1 additional day. For more details, please refer to the Appendix.

[Figure 56]

[Figure 57]

[Figure 58]

[Figure 59]

[Figure 60]

[Figure 61]

[Figure 62]

[Figure 63]

[Figure 64]

[Figure 65]

[Figure 66]

[Figure 67]

21.63 28.12 22.84 30.45

[Figure 68]

[Figure 69]

[Figure 70]

[Figure 71]

[Figure 72]

[Figure 73]

[Figure 74]

[Figure 75]

[Figure 76]

[Figure 77]

[Figure 78]

[Figure 79]

[Figure 80]

[Figure 81]

[Figure 82]

[Figure 83]

17.16 28.36 18.76 28.46 Input images Ground truth LGM Ours Ground truth LGM Ours

- Fig. 4: Visual comparisons to LGM [61]. The LGM renderings have obvious distorted textures (top) and broken geometries (bottom) and are inferior in recovering accurate surface opacity (top left; bottom left; bottom right). Our GS-LRM renderings recover the high-frequency details and are visually much closer to the ground truth. PSNRs are shown under each image.

#### 4.3 Evaluation against Baselines

Object-level. We compare our object-level GS-LRM with the Triplane-LRM in Instant3D [32]. We outperform this baseline by a large margin across all view synthesis metrics; for example, as shown in Tab. 1, we improve the PSNR for novel-view rendering by 3.98dB on GSO data, and by 1.59dB on ABO data. This is also reflected by our much sharper renderings in Fig. 3; our GS-LRM manages to faithfully reproduce the high-frequency details, e.g., texts, in the input images, while Triplane-LRM tends to blur out the details. We attribute this to our pixel-aligned Gaussian prediction scheme which creates a shortcut for learning accurate per-Gaussian colors from input RGB images; this is in contrast to the non-pixel-aligned prediction of triplanes in Instant3D’s LRM where the relationship between input pixel colors and triplane features is less straightforward, and might be more challenging to learn for the network. Another advantage of our GS-LRM is that our predicted Gaussians are much faster to render than the predicted NeRF from Triplane-LRM, making it easier to deploy in downstream applications. We also tried to compare against another baseline SparseNeuS [36]; however, we found that it failed to produce plausible reconstructions given 4 highly sparse inputs; this was also observed in the prior Instant3D work (they had to use 8 views to run SparseNeuS, which is not a fair comparison).

In addition, we compare with the concurrent work LGM [61] which is also based on Gaussian Splatting [30] . The official LGM is trained with a special setting using 256×256 resolution input and 512×512 resolution output supervision. Since their model only accepts 256×256 input, we compare with LGM using our low-res model, trained with 256×256 images only from our 256-res pre-training stage. We evaluate both models with 256×256 renderings for comparison. As

[Figure 84]

[Figure 85]

[Figure 86]

[Figure 87]

[Figure 88]

[Figure 89]

[Figure 90]

[Figure 91]

pixelSplatOursGroudtruthInputimages

[Figure 92]

[Figure 93]

[Figure 94]

[Figure 95]

[Figure 96]

[Figure 97]

[Figure 98]

[Figure 99]

[Figure 100]

[Figure 101]

[Figure 102]

[Figure 103]

23.21

20.82

24.89

22.17

[Figure 104]

[Figure 105]

[Figure 106]

[Figure 107]

[Figure 108]

[Figure 109]

[Figure 110]

[Figure 111]

28.03

28.84

26.37

25.50

- Fig. 5: We compare scene-level GS-LRM with the best-performing baseline pixelSplat [8]. We can observe that our model is better in sharpness (leftmost column), has fewer floaters (mid-right and rightmost), and is more faithful to the original scenes (mid-left). Our superiority in visual quality aligns with the significant quantitative metric improvement in Tab. 1. PSNRs are shown at the corner of each image.

seen in Tab. 1, our approach significantly outperforms LGM, achieving a notable 8dB higher PSNR on both GSO and ABO testing data. The improvement can be visualized in Fig. 4. It’s worth noting that this is an almost equal-compute comparison: LGM is trained on 32 A100 (80G VRAM) for 4 days, while our lowres base model is trained using 64 A100 (40G VRAM) for 2 days. This further highlights the method-wise advantage of our GS-LRM — a transformer model predicting per-pixel Gaussians that scales up easily with data and compute.

Scene-level. We compare our scene-level GS-LRM against previous generalizable neural rendering techniques [22, 57, 72] and the state-of-the-art GS-based concurrent work pixelSplat [8]. Since pixelSplat and GPNR are trained at 256× 256 image resolution, we use our low-res model in these comparisons, and follow exactly the same evaluation setting as in pixelSplat. We directly take the reported quantitative results for all baselines from pixelSplat [8]. As shown in Tab. 1, our approach achieves the best quantitative results on the RealEstate10k

testing set, substantially surpassing all baselines for all metrics. In particular, when compared to pixelSplat, the top-performing baseline, our model leads to significant improvements of 2.2db in PSNR, 0.034 in SSIM, and 0.028 in LPIPS. These metric improvements align with the visual comparisons in Fig. 5, where our results are sharper and have fewer floaters. Note that pixelSplat and other baseline methods all leverage more complex model designs such as epipolar linebased feature aggregation. In contrast, we utilize a straightforward transformer model with self-attention layers. These self-attention layers effectively learn to aggregate context information from all the intra-view and inter-view pixels (as opposed to a subset of them on epipolar lines) for accurate per-pixel Gaussian prediction, when trained on large amount of data.

#### 4.4 High-resolution Qualitative Results

We showcase some high-res reconstructions of our GS-LRM in Fig. 6. For the object captures, texts on the top-left product box remain readable in our rendered novel views, even when the inputs are captured from oblique viewpoints; we also manage to reconstruct the challenging thin structures and transparent glasses in the top-right table example. For the scene captures, we are able to handle large outdoor depth variations and faithfully reproduce complex structures, e.g., trees, in the presented examples. Please refer to our project page for videos and interactive rendering results.

#### 4.5 Applications in 3D Generation

Following the Instant3D [32] work, we can also chain our GS-LRM with a textconditioned or image-conditioned multi-view generator to achieve text-to-3D or image-to-3D. We qualitatively show some results to demonstrate such a workflow for applying our models in this downstream 3D generation task.

Text/Image-to-object. For the text-to-3D application, we use the finetuned SDXL [46] model in Instant3D as the text-to-multi-views generator. Since the above generator generates four structured views with known camera parameters, we directly feed these posed images into our object-level GS-LRM to get

- 3D GS instantly. The results are visualized in Fig. 7 (top two rows). We provide both novel view renderings and point clouds for illustrating the appearance and geometry, respectively. For the image-to-3D application, we use the imageconditioned multi-view diffusion model in Zero123++ [54], which generates 6 structured views at fixed viewpoints. Though being trained with 4 input views, our transformer-based GS-LRM can take a variable number of images, e.g., 6 images, during inference; hence we simply input the 6 generated images (along with their cameras) into our object-level GS-LRM to predict the 3D Gaussians. We also show our novel-view renderings and a point cloud visualization of 3D Gaussians in Fig. 7 (bottom two rows).

Text-to-scene. We adopt the recently proposed Sora video generation model [43] as the multi-view scene generator from texts. As the Sora model has not publicly

[Figure 112]

[Figure 113]

InputimagesInputimagesRenderednovelviewRenderednovelview

[Figure 114]

[Figure 115]

[Figure 116]

[Figure 117]

[Figure 118]

[Figure 119]

[Figure 120]

[Figure 121]

- Fig. 6: We show high-res novel-view renderings from our predicted GS given highres input images (4 512×512 images for objects, and 2 512×904 images for a scene; rendering resolution is the same to the input), to demonstrate our GS-LRM’s capability to represent fine-grained details, e.g., readable texts (top left), translucent and thin structures (top right, bottom). Image sources are from GSO (top left), ABO (top right), and RealEstate10K (bottom).

##### released, we use the generated videos published in [43]. Our current model is limited to static scenes only, and we thus pick the generated videos from relevant

[Figure 122]

[Figure 123]

[Figure 124]

[Figure 125]

[Figure 126]

[Figure 127]

[Figure 128]

[Figure 129]

A bear dressed in medieval armor

A dog made of vegetables

[Figure 130]

[Figure 131]

[Figure 132]

[Figure 133]

[Figure 134]

[Figure 135]

A brightly colored mushroom growing on a log A covered wagon

[Figure 136]

[Figure 137]

[Figure 138]

[Figure 139]

[Figure 140]

[Figure 141]

Input Input

[Figure 142]

[Figure 143]

[Figure 144]

[Figure 145]

Input

Input

- Fig. 7: Text-to-3D (top two rows) and image-to-3D (bottom two rows) results by chaining Instant3D’s [32] text-conditioned and Zero123++’s [54] image-conditioned multi-view generators to our GS-LRM reconstructor. For each result, we show novel view renderings and a visualization of the point cloud with point positions and colors extracted from the predicted Gaussians.

text prompt guidance. We use COLMAP [51] to register the video frames, then feed a selected sparse subset of posed frames into our scene-level GS-LRM to reconstruct the 3D scene. The visualization is in Fig. 8.

#### 4.6 Limitations

Although our method shows high-quality reconstruction results from posed sparse images, there are still a few limitations to be addressed in future work. Firstly, the highest resolution our model can currently operate on is about 512 × 904; it is of significant interest to extend the model to work on 1K, even 2K resolution images for best visual quality. Secondly, our model requires known camera parameters; this assumption may not be practical in certain application scenarios (e.g., a user only captures 4 views around an object, making it extremely challenging for SfM to work). To make our model more practical, it is interesting to explore ways to get rid of the camera parameters from the input end [28,63,65]. Thirdly, the pixel-aligned representation only explicitly models the surface inside

[Figure 146]

RenderednovelviewInputimages

[Figure 147]

[Figure 148]

[Figure 149]

[Figure 150]

[Figure 151]

- Fig. 8: Text-to-scene result. We take the generated video from the Sora text-to-video model [43] (Prompt: drone view of waves crashing against the rugged cliffs along Big Sur’s garay point beach). We select 4 frames and reconstruct the 3D scene from them using our scene-level GS-LRM. We show novel-view RGB/depth rendering from our predicted GS (top) and 4 input images (bottom). Please refer to our project page for the video and interactive rendering results.

the view frustum, which means that unseen regions cannot be reconstructed. We found that the model has a certain ability to re-purposing points for hallucinating unseen parts (also observed in [60]), but this capacity is limited and not guaranteed. We leave it to future work to improve the unseen regions.

### 5 Conclusion

In this work, we present a simple and scalable transformer-based large reconstruction model for Gaussian Splatting (GS) representation. Our method enables fast feed-forward high-res GS prediction from a sparse set of posed images in ∼0.23 seconds on a single A100 GPU. Our model can work on both object-level and scene-level captures, and achieves state-of-the-art performance in both scenarios when trained on large amount of data. We hope that our work can inspire more future work in the space of data-driven feed-forward 3D reconstruction.

### Acknowledgement

We thank Nathan Carr and Duygu Ceylan for useful discussions.

### References

- 1. Agarwal, S., Furukawa, Y., Snavely, N., Simon, I., Curless, B., Seitz, S.M., Szeliski, R.: Building rome in a day. Communications of the ACM 54(10), 105–112 (2011) 3
- 2. Aliev, K.A., Sevastopolsky, A., Kolos, M., Ulyanov, D., Lempitsky, V.: Neural point-based graphics. In: Computer Vision–ECCV 2020: 16th European Conference, Glasgow, UK, August 23–28, 2020, Proceedings, Part XXII 16. pp. 696–712. Springer (2020) 3
- 3. Ba, J.L., Kiros, J.R., Hinton, G.E.: Layer normalization. arXiv preprint arXiv:1607.06450 (2016) 5
- 4. Barron, J.T., Mildenhall, B., Tancik, M., Hedman, P., Martin-Brualla, R., Srinivasan, P.P.: Mip-nerf: A multiscale representation for anti-aliasing neural radiance fields. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 5855–5864 (2021) 3
- 5. Barron, J.T., Mildenhall, B., Verbin, D., Srinivasan, P.P., Hedman, P.: Mipnerf 360: Unbounded anti-aliased neural radiance fields. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 5470– 5479 (2022) 3
- 6. Barron, J.T., Mildenhall, B., Verbin, D., Srinivasan, P.P., Hedman, P.: Zip-nerf: Anti-aliased grid-based neural radiance fields. arXiv preprint arXiv:2304.06706

(2023) 3

- 7. Chan, E.R., Lin, C.Z., Chan, M.A., Nagano, K., Pan, B., De Mello, S., Gallo, O., Guibas, L.J., Tremblay, J., Khamis, S., et al.: Efficient geometry-aware 3d generative adversarial networks. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 16123–16133 (2022) 1, 3
- 8. Charatan, D., Li, S., Tagliasacchi, A., Sitzmann, V.: pixelsplat: 3d gaussian splats from image pairs for scalable generalizable 3d reconstruction. arXiv preprint arXiv:2312.12337 (2023) 4, 7, 8, 10
- 9. Chen, A., Xu, Z., Geiger, A., Yu, J., Su, H.: Tensorf: Tensorial radiance fields. In: European Conference on Computer Vision (ECCV) (2022) 1, 3, 8
- 10. Chen, A., Xu, Z., Wei, X., Tang, S., Su, H., Geiger, A.: Dictionary fields: Learning a neural basis decomposition. ACM Transactions on Graphics (TOG) 42(4), 1–12

(2023) 3

- 11. Chen, A., Xu, Z., Wei, X., Tang, S., Su, H., Geiger, A.: Factor fields: A unified framework for neural fields and beyond. arXiv preprint arXiv:2302.01226 (2023) 3
- 12. Chen, A., Xu, Z., Zhao, F., Zhang, X., Xiang, F., Yu, J., Su, H.: Mvsnerf: Fast generalizable radiance field reconstruction from multi-view stereo. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 14124–14133

(2021) 4

- 13. Chen, E.M., Holalkere, S., Yan, R., Zhang, K., Davis, A.: Ray conditioning: Trading photo-consistency for photo-realism in multi-view image generation. In: Proceedings of the IEEE/CVF International Conference on Computer Vision (ICCV). pp. 23242–23251 (October 2023) 4
- 14. Chen, Q., Koltun, V.: Photographic image synthesis with cascaded refinement networks. In: Proceedings of the IEEE international conference on computer vision. pp. 1511–1520 (2017) 6
- 15. Chen, T., Xu, B., Zhang, C., Guestrin, C.: Training deep nets with sublinear memory cost. arXiv preprint arXiv:1604.06174 (2016) 8, 20

- 16. Cheng, S., Xu, Z., Zhu, S., Li, Z., Li, L.E., Ramamoorthi, R., Su, H.: Deep stereo using adaptive thin volume representation with uncertainty awareness. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 2524–2534 (2020) 3
- 17. Collins, J., Goel, S., Deng, K., Luthra, A., Xu, L., Gundogdu, E., Zhang, X., Vicente, T.F.Y., Dideriksen, T., Arora, H., et al.: Abo: Dataset and benchmarks for real-world 3d object understanding. In: CVPR. pp. 21126–21136 (2022) 7
- 18. Dao, T.: Flashattention-2: Faster attention with better parallelism and work partitioning. arXiv preprint arXiv:2307.08691 (2023) 8, 20
- 19. Deitke, M., Schwenk, D., Salvador, J., Weihs, L., Michel, O., VanderBilt, E., Schmidt, L., Ehsani, K., Kembhavi, A., Farhadi, A.: Objaverse: A universe of annotated 3d objects. In: CVPR. pp. 13142–13153 (2023) 3, 7
- 20. Dosovitskiy, A., Beyer, L., Kolesnikov, A., Weissenborn, D., Zhai, X., Unterthiner, T., Dehghani, M., Minderer, M., Heigold, G., Gelly, S., et al.: An image is worth 16x16 words: Transformers for image recognition at scale. In: International Conference on Learning Representations (2020) 4, 5
- 21. Downs, L., Francis, A., Koenig, N., Kinman, B., Hickman, R., Reymann, K., McHugh, T.B., Vanhoucke, V.: Google scanned objects: A high-quality dataset of 3d scanned household items. In: 2022 International Conference on Robotics and Automation (ICRA). pp. 2553–2560. IEEE (2022) 7
- 22. Du, Y., Smith, C., Tewari, A., Sitzmann, V.: Learning to render novel views from wide-baseline stereo pairs. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 4970–4980 (2023) 7, 10
- 23. Furukawa, Y., Ponce, J.: Accurate, dense, and robust multiview stereopsis. IEEE transactions on pattern analysis and machine intelligence 32(8), 1362–1376 (2009) 1, 3
- 24. Gao, Q., Xu, Q., Su, H., Neumann, U., Xu, Z.: Strivec: Sparse tri-vector radiance fields. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 17569–17579 (2023) 3
- 25. Gu, X., Fan, Z., Zhu, S., Dai, Z., Tan, F., Tan, P.: Cascade cost volume for high-resolution multi-view stereo and stereo matching. In: Proceedings of the IEEE/CVF conference on computer vision and pattern recognition. pp. 2495–2504

(2020) 3

- 26. He, K., Zhang, X., Ren, S., Sun, J.: Deep residual learning for image recognition. In: Proceedings of the IEEE conference on computer vision and pattern recognition. pp. 770–778 (2016) 5
- 27. Hong, Y., Zhang, K., Gu, J., Bi, S., Zhou, Y., Liu, D., Liu, F., Sunkavalli, K., Bui, T., Tan, H.: Lrm: Large reconstruction model for single image to 3d (2023) 1, 4, 6, 7
- 28. Jiang, H., Jiang, Z., Zhao, Y., Huang, Q.: Leap: Liberate sparse-view 3d modeling from camera poses. ArXiv 2310.01410 (2023) 13
- 29. Johari, M.M., Lepoittevin, Y., Fleuret, F.: Geonerf: Generalizing nerf with geometry priors. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 18365–18375 (2022) 4
- 30. Kerbl, B., Kopanas, G., Leimkühler, T., Drettakis, G.: 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics 42(4) (2023) 1, 2, 3, 6, 9, 21, 22
- 31. Lefaudeux, B., Massa, F., Liskovich, D., Xiong, W., Caggiano, V., Naren, S., Xu, M., Hu, J., Tintore, M., Zhang, S., Labatut, P., Haziza, D., Wehrstedt, L., Reizenstein, J., Sizov, G.: xformers: A modular and hackable transformer modelling library. https://github.com/facebookresearch/xformers (2022) 8, 20

- 32. Li, J., Tan, H., Zhang, K., Xu, Z., Luan, F., Xu, Y., Hong, Y., Sunkavalli, K., Shakhnarovich, G., Bi, S.: Instant3d: Fast text-to-3d with sparse-view generation and large reconstruction model (2023) 1, 4, 6, 7, 8, 9, 11, 13
- 33. Lin, K.E., Xu, Z., Mildenhall, B., Srinivasan, P.P., Hold-Geoffroy, Y., DiVerdi, S., Sun, Q., Sunkavalli, K., Ramamoorthi, R.: Deep multi depth panoramas for view synthesis. In: European Conference on Computer Vision. pp. 328–344. Springer

(2020) 3

- 34. Liu, L., Gu, J., Zaw Lin, K., Chua, T.S., Theobalt, C.: Neural sparse voxel fields. Advances in Neural Information Processing Systems 33, 15651–15663 (2020) 3
- 35. Lombardi, S., Simon, T., Schwartz, G., Zollhoefer, M., Sheikh, Y., Saragih, J.: Mixture of volumetric primitives for efficient neural rendering. ACM Transactions on Graphics (ToG) 40(4), 1–13 (2021) 3
- 36. Long, X., Lin, C., Wang, P., Komura, T., Wang, W.: Sparseneus: Fast generalizable neural surface reconstruction from sparse views. In: European Conference on Computer Vision. pp. 210–227. Springer (2022) 4, 9
- 37. Loshchilov, I., Hutter, F.: Decoupled weight decay regularization. arXiv preprint arXiv:1711.05101 (2017) 20
- 38. Micikevicius, P., Narang, S., Alben, J., Diamos, G., Elsen, E., Garcia, D., Ginsburg, B., Houston, M., Kuchaiev, O., Venkatesh, G., et al.: Mixed precision training. In: International Conference on Learning Representations (2018) 8, 20
- 39. Mildenhall, B., Srinivasan, P.P., Ortiz-Cayon, R., Kalantari, N.K., Ramamoorthi, R., Ng, R., Kar, A.: Local light field fusion: Practical view synthesis with prescriptive sampling guidelines. ACM Transactions on Graphics (TOG) 38(4), 1–14

(2019) 3

- 40. Mildenhall, B., Srinivasan, P.P., Ortiz-Cayon, R., Kalantari, N.K., Ramamoorthi, R., Ng, R., Kar, A.: Local light field fusion: Practical view synthesis with prescriptive sampling guidelines. ACM Transactions on Graphics (TOG) (2019) 8
- 41. Mildenhall, B., Srinivasan, P.P., Tancik, M., Barron, J.T., Ramamoorthi, R., Ng, R.: Nerf: Representing scenes as neural radiance fields for view synthesis. In: ECCV

(2020) 1, 3

- 42. Müller, T., Evans, A., Schied, C., Keller, A.: Instant neural graphics primitives with a multiresolution hash encoding. ACM Transactions on Graphics (ToG) 41(4), 1– 15 (2022) 1, 3
- 43. OpenAI: Creating video from text (February 2024), https://openai.com/sora 2, 11, 12, 14
- 44. Peng, S., Niemeyer, M., Mescheder, L., Pollefeys, M., Geiger, A.: Convolutional occupancy networks. In: Computer Vision–ECCV 2020: 16th European Conference, Glasgow, UK, August 23–28, 2020, Proceedings, Part III 16. pp. 523–540. Springer

(2020) 1

- 45. Plücker, J.: Xvii. on a new geometry of space. Philosophical Transactions of the Royal Society of London (155), 725–791 (1865) 4
- 46. Podell, D., English, Z., Lacey, K., Blattmann, A., Dockhorn, T., Müller, J., Penna, J., Rombach, R.: Sdxl: Improving latent diffusion models for high-resolution image synthesis. In: The Twelfth International Conference on Learning Representations

(2023) 11

- 47. Pollefeys, M., Nistér, D., Frahm, J.M., Akbarzadeh, A., Mordohai, P., Clipp, B., Engels, C., Gallup, D., Kim, S.J., Merrell, P., et al.: Detailed real-time urban 3d reconstruction from video. International Journal of Computer Vision 78, 143–167

(2008) 3

- 48. Pollefeys, M., Van Gool, L., Vergauwen, M., Verbiest, F., Cornelis, K., Tops, J., Koch, R.: Visual modeling with a hand-held camera. International Journal of Computer Vision 59, 207–232 (2004) 3
- 49. Rogozhnikov, A.: Einops: Clear and reliable tensor manipulations with einstein-like notation. In: International Conference on Learning Representations (2021) 20
- 50. Schonberger, J.L., Frahm, J.M.: Structure-from-motion revisited. In: Proceedings of the IEEE conference on computer vision and pattern recognition. pp. 4104–4113

(2016) 1, 3

- 51. Schönberger, J.L., Frahm, J.M.: Structure-from-motion revisited. In: Conference on Computer Vision and Pattern Recognition (CVPR) (2016) 7, 13
- 52. Schönberger, J.L., Zheng, E., Pollefeys, M., Frahm, J.M.: Pixelwise view selection for unstructured multi-view stereo. In: European Conference on Computer Vision (ECCV) (2016) 1, 3
- 53. Shen, Z., Dai, Y., Rao, Z.: Cfnet: Cascade and fused cost volume for robust stereo matching. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 13906–13915 (2021) 3
- 54. Shi, R., Chen, H., Zhang, Z., Liu, M., Xu, C., Wei, X., Chen, L., Zeng, C., Su, H.: Zero123++: a single image to consistent multi-view diffusion base model (2023) 11, 13
- 55. Simonyan, K., Zisserman, A.: Very deep convolutional networks for large-scale image recognition. arXiv preprint arXiv:1409.1556 (2014) 6
- 56. Snavely, N., Seitz, S.M., Szeliski, R.: Photo tourism: exploring photo collections in 3d. In: ACM siggraph 2006 papers, pp. 835–846 (2006) 3
- 57. Suhail, M., Esteves, C., Sigal, L., Makadia, A.: Generalizable patch-based neural rendering. In: European Conference on Computer Vision. Springer (2022) 4, 7, 10
- 58. Suhail, M., Esteves, C., Sigal, L., Makadia, A.: Light field neural rendering. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 8269–8279 (2022) 4
- 59. Sun, C., Sun, M., Chen, H.T.: Direct voxel grid optimization: Super-fast convergence for radiance fields reconstruction. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 5459–5469 (2022) 3
- 60. Szymanowicz, S., Rupprecht, C., Vedaldi, A.: Splatter image: Ultra-fast single-view 3d reconstruction. arXiv: (2023) 14
- 61. Tang, J., Chen, Z., Chen, X., Wang, T., Zeng, G., Liu, Z.: Lgm: Large multiview gaussian model for high-resolution 3d content creation. arXiv preprint arXiv:2402.05054 (2024) 4, 7, 9
- 62. Vaswani, A., Shazeer, N., Parmar, N., Uszkoreit, J., Jones, L., Gomez, A.N., Kaiser, Ł., Polosukhin, I.: Attention is all you need. Advances in neural information processing systems 30 (2017) 5
- 63. Wang, P., Tan, H., Bi, S., Xu, Y., Luan, F., Sunkavalli, K., Wang, W., Xu, Z., Zhang, K.: Pf-lrm: Pose-free large reconstruction model for joint pose and shape prediction. arXiv preprint arXiv:2311.12024 (2023) 1, 4, 5, 6, 13
- 64. Wang, Q., Wang, Z., Genova, K., Srinivasan, P.P., Zhou, H., Barron, J.T., MartinBrualla, R., Snavely, N., Funkhouser, T.: Ibrnet: Learning multi-view image-based rendering. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 4690–4699 (2021) 4
- 65. Wang, S., Leroy, V., Cabon, Y., Chidlovskii, B., Revaud, J.: Dust3r: Geometric 3d vision made easy. arXiv preprint arXiv:2312.14132 (2023) 13
- 66. Wiles, O., Gkioxari, G., Szeliski, R., Johnson, J.: Synsin: End-to-end view synthesis from a single image. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 7467–7477 (2020) 3

- 67. Xu, Q., Xu, Z., Philip, J., Bi, S., Shu, Z., Sunkavalli, K., Neumann, U.: Point-nerf: Point-based neural radiance fields. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 5438–5448 (2022) 3
- 68. Xu, Y., Tan, H., Luan, F., Bi, S., Wang, P., Li, J., Shi, Z., Sunkavalli, K., Wetzstein, G., Xu, Z., Zhang, K.: Dmv3d: Denoising multi-view diffusion using 3d large reconstruction model (2023) 1, 4, 6
- 69. Yao, Y., Luo, Z., Li, S., Fang, T., Quan, L.: Mvsnet: Depth inference for unstructured multi-view stereo. In: Proceedings of the European conference on computer vision (ECCV). pp. 767–783 (2018) 3
- 70. Yao, Y., Luo, Z., Li, S., Shen, T., Fang, T., Quan, L.: Recurrent mvsnet for highresolution multi-view stereo depth inference. In: Proceedings of the IEEE/CVF conference on computer vision and pattern recognition. pp. 5525–5534 (2019) 3
- 71. Yifan, W., Serena, F., Wu, S., Öztireli, C., Sorkine-Hornung, O.: Differentiable surface splatting for point-based geometry processing. ACM Transactions on Graphics (proceedings of ACM SIGGRAPH ASIA) 38(6) (2019) 3
- 72. Yu, A., Ye, V., Tancik, M., Kanazawa, A.: pixelnerf: Neural radiance fields from one or few images. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 4578–4587 (2021) 3, 4, 7, 10
- 73. Zhang, K., Kolkin, N., Bi, S., Luan, F., Xu, Z., Shechtman, E., Snavely, N.: Arf: Artistic radiance fields (2022) 8, 20
- 74. Zhang, K., Riegler, G., Snavely, N., Koltun, V.: Nerf++: Analyzing and improving neural radiance fields. arXiv preprint arXiv:2010.07492 (2020) 3
- 75. Zhang, R., Isola, P., Efros, A.A., Shechtman, E., Wang, O.: The unreasonable effectiveness of deep features as a perceptual metric. In: CVPR (2018) 6
- 76. Zhou, T., Tucker, R., Flynn, J., Fyffe, G., Snavely, N.: Stereo magnification: Learning view synthesis using multiplane images. arXiv preprint arXiv:1805.09817 (2018) 3, 7

### A Appendix

- A.1 Pseudo Code

We list the pseudo code of our GS-LRM in Algorithm 1 1. The code implements the method that we discussed in the main method section, and also the Gaussian parametrization detailed later in Sec. A.4.

- A.2 Additional Model Details

We do not use bias term throughout our model, which includes both Linear and LayerNorm layers. We initialize the model weights with a normal distribution of zero-mean and 0.02-stddev.

- A.3 Additional Training Details

We train our model with AdamW [37] optimizer. The β1, β2 are set to 0.9 and 0.95 respectively. We use a weight decay of 0.05 on all parameters except the those of the LayNorm layers. We use a cosine learning rate decay with linear warmup. We take 2000 step of warm up and the peak learning rate is set to

- 4e − 4. The model is trained for 80K iterations on the 256-res training, and then fine-tuned with 512-res for another 20K iterations. Finetuing at 512-res uses 500-step warmup with the peak learning rate 1e − 4 in the cosine learning rate decay schedule. We use a per-GPU batch size of 8 objects/scenes during 256-res training, and a per-GPU batch size of 2 during 512-res finetuning. For each object, we use 4 input views and 4 novel supervision views at each iteration of 256-res and 512-res training; for each scene, we use 2 input views and 6 novel supervison views, following the protocol of pixelSplat. We use λ = 0.5 to balance the MSE loss and Perceptual loss. To enable efficient training and inference, we adopt Flash-Attention-v2 [18] in the xFormers [31] library, gradient checkpointing [15], and mixed-precision training [38] with BF16 data type. We also apply deferred backpropagation [73] for rendering the GS to save GPU memory. 256-res training takes about 2 days on 64 A100 (40G VRAM) GPUs, while 512-res finetuning costs 1 additional day.

- A.4 3D Gaussian Parameterization

As 3D Gaussians are unstructured explicit representation (i.e., different from Triplane-NeRF’s structural implicit representation), the parameterization of the output parameters can largely affect the model’s convergence. For here, the

1 To avoid the the shaping constraints of the CUDNN kernel, we use Einops [49] and Linear layer to implement the patchify and unpatchify operator, but they are conceptually the same to the conv/deconv operator. For clarity, we use conv/deconv in pseudo code.

##### Algorithm 1 GS-LRM pseudo code.

# Input list: # image: [b, n, h, w, 3], n is number of views; h and w are the height and width # extrinsic: [b, n, 4, 4] # intrinsic: [b, n, 4] # # Output list (3D GS parameters): # xyz: [b, *, 3], rgb [b, *, 3], scaling [b, *, 3], rotation [b, *, 4], opacity [b, *, 1]

# GS-LRM transformer o, d = rays_from_camera(extrinsic, intrinsic) # rays_origin, rays_direction: [b, n, h, w,

3] x = concat([image, o, cross(o, d)], dim=-1) # [b, n, h, w, 9] x = conv(x, out=d, kernel=8, stride=8) # patchify to [b, n, h/8, w/8, d] x = x.reshape(b, -1, d) # Sequentialize as transformer input [b, n * h/8 * w/8, d] x = transformer(LN(x)) x = x.reshape(b, n, h//8, w//8, d) x = deconv(LN(x), out=12, kernel=8, stride=8) # unpatchify to GS output: [b, n, h, w, 12] x = x.reshape(b, -1, 12) # Simply merge all Gaussians together [b, n * h * w, 12]

# GS parameterization distance, rgb, scaling, rotation, opacity = x.split([1, 3, 3, 4, 1], dim=-1) w = sigmoid(distance) xyz = o + d * (near * (1 - w) + far * w) scaling = min(exp(scaling - 2.3), 0.3) rotation = rotation / rotation.norm(dim=-1, keepdim=True) opacity = sigmoid(opacity - 2.0)

return xyz, rgb, scaling, rotation, opacity

‘structural’ and ‘unstructual’ mainly refer to whether each token have a determinitic spatial meaning. We discuss in detail how we implement the parameterization for reproducibility.

Scale and opacity. For the scale and opacity of the Gaussian Splatting, we apply the default activations used by Gaussian Splatting [30] to map the range to R+ and (0,1). For scale, we use exponential activation (which is R −→ R+). For opacity, we use the Sigmoid activation defined as σ(x) = 1/(1+exp(−x)) (which is R −→ (0,1)). Besides the activations, we also want the initial output to be close to 0.1. We accompolished this by adding constant bias to the transformer’s output to shift the initialization. We also clip the scales at a maximum size of 0.3. This max-scale clipping is applied because we empirically found that the scale of the 3D Gaussian can be very large (and the Gaussian will be degenerated to a long line) without such clipping. These line-shaped Gaussians can spread the gradients to multiple pixels after splatting and we found that it hurt the training stability. In summary, according to the main method section, suppose Gij is the output parameters of Gaussians, and we split it into the components of (Grgb,Gscale,Grotation,Gopacity,Gdistance); he equation for scale and opacity would be

scale = min{exp(Gscale − 2.3),0.3}, (6) opacity = σ(Gopacity − 2.0), (7)

where exp(−2.3) and σ(−2.0) are both 0.1 approximately. As the output Gij is designed to be zero-mean after the model-weight initialization (we also remove

all bias terms as mentioned earlier). We can approximately get an output GS initialization that we desire. Note that this initialization does not need to be accurate because it is mostly used to help training stability.

Rotation. We predict unnormalized quaternions and use L2-normalize as activations to get unit quaternions.

RGB. We directly interpret the model output as the zero-order Spherical Harmonics coefficients used in Gaussian Splatting implementation [30]. We do not use higher-order Spherical Harmonics in this work for simplicity. We leave it to future work to improve the view-dependent modelling of our GS-LRM.

XYZ and Distance. In the main paper, we briefly mention that the Gaussian center is parameterized as xyz = rayo + t · rayd. To convert the transformers’ output Gdistance to t, we employ an empirical near distance dnear and far distance dfar. We then map our model output to the range of (dnear,dfar). The conversion is defined as

ω = σ(Gdistance), (8) t = (1 − ω) dnear + ω dfar. (9)

The dnear and dfar are set differently for the object-level GS-LRM and scene-level GS-LRM. For object-level GS-LRM, we use dnear = 0.1 and dfar = 4.5 and clip the predicted XYZ to be inside [−1,1]3; this is aligned with our training data rendering setup. For scene-level GS-LRM, we use dnear = 0.0 and dfar = 500 to account for the large depth variations of indoor and outdoor scenes.

#### A.5 Camera Pose Normalization

For object-level GS-LRM, we did not use any camera normalization, as the object sizes are pre-normalized before data generation. For scene-level GS-LRM, we first compute the mean camera pose by averaging all input camera poses and consider the coordinate frame of the mean camera as the world space, i.e. making input poses relative to the mean pose for subsequent processes. We then scale all input camera locations, so that they are located within the bounding box ([−1,1]3) in the world space.

