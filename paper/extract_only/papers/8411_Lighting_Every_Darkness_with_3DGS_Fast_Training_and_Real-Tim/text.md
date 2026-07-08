## Lighting Every Darkness with 3DGS: Fast Training and Real-Time Rendering for HDR View Synthesis

[Figure 1]

[Figure 2]

[Figure 3]

##### Xin Jin1,2∗ Pengyi Jiao1∗ Zheng-Peng Duan1 Xingchao Yang2 Chun-Le Guo1† Bo Ren1† Chongyi Li1

1 VCIP, CS, Nankai University 2 MEGVII Technology

https://srameo.github.io/projects/le3d

# arXiv:2406.06216v1[cs.CV]10Jun2024

Noisy RAW

[Figure 4]

[Figure 5]

[Figure 6]

[Figure 7]

[Figure 8]

| |
|---|

(a) Exposure Variation (b) Changing WB, HDR

[Figure 9]

[Figure 10]

LE3D (Ours)

156 GPU×H 0.02 FPS 1.28 GPU×H 100 FPS 1.50 GPU×H 83 FPS

RawNeRF RawGS (Baseline) LE3D (Ours) (c) Focus on Foreground (d) Changing WB, Focus on Background

[28]

Figure 1: LE3D reconstructs a 3DGS representation of a scene from a set of multi-view noisy RAW images. As shown on the left, LE3D features fast training and real-time rendering capabilities compared to RawNeRF [28]. Moreover, compared to RawGS (a 3DGS [19] we trained with RawNeRF’s strategy), LE3D demonstrates superior noise resistance and the ability to represent HDR linear colors. The right side highlights the variety of real-time downstream tasks LE3D can perform, including (a) exposure variation, (b, d) changing White Balance (WB), (b) HDR rendering, and (c, d) refocus.

### Abstract

Volumetric rendering based methods, like NeRF, excel in HDR view synthesis from RAW images, especially for nighttime scenes. While, they suffer from long training times and cannot perform real-time rendering due to dense sampling requirements. The advent of 3D Gaussian Splatting (3DGS) enables real-time rendering and faster training. However, implementing RAW image-based view synthesis directly using 3DGS is challenging due to its inherent drawbacks: 1) in nighttime scenes, extremely low SNR leads to poor structure-from-motion (SfM) estimation in distant views; 2) the limited representation capacity of spherical harmonics (SH) function is unsuitable for RAW linear color space; and 3) inaccurate scene structure hampers downstream tasks such as refocusing. To address these issues, we propose LE3D (Lighting Every darkness with 3DGS). Our method proposes Cone Scatter Initialization to enrich the estimation of SfM, and replaces SH with a Color MLP to represent the RAW linear color space. Additionally, we introduce depth distortion and near-far regularizations to improve the accuracy of scene structure for downstream tasks. These designs enable LE3D to perform real-time novel view synthesis, HDR rendering, refocusing, and tone-mapping changes. Compared to previous volumetric rendering based methods, LE3D reduces training time to 1% and improves rendering speed by up to 4,000 times for 2K resolution images in terms of FPS. Code and viewer can be found in https://github.com/Srameo/LE3D.

∗Equal Contribution. This project is done during Xin Jin’s internship at MEGVII Technology. †C. L. Guo and B. Ren ({guochunle,rb}@nankai.edu.cn) are corresponding authors.

Preprint. Under review.

### 1 Introduction

Since the advent of Neural Radiance Fields (NeRF) [29], novel view synthesis (NVS) has entered a period of vigorous development, thereby advancing the progress of related applications in augmented and virtual reality (AR/VR). Existing NVS technologies predominantly utilize multiple well-exposed and noise-free low dynamic range (LDR) RGB images as inputs to reconstruct 3D scenes. This significantly impacts the capability to capture high-quality images in environments with low light or high contrast, such as nighttime settings or areas with stark lighting differences. These scenarios typically necessitate the use of high dynamic range (HDR) scene reconstruction techniques.

Existing HDR scene reconstruction techniques primarily fall into two categories and all are based on volumetric rendering: 1) using multiple-exposure LDR RGB images for supervised training [17], and 2) conducting training directly on noisy RAW data [28]. The first type of method is typically highly effective in well-lit scenes. However, in nighttime scenarios, its reconstruction performance is constrained due to the impact of the limited dynamic range in sRGB data [4]. While RAW data preserves more details in nighttime scenes, it is also more susceptible to noise. Therefore, RawNeRF [28] is proposed to address the issue of vanilla NeRF’s lack of noise resistance. However, RawNeRF suffers from prolonged training times and an inability to render in real-time (a common drawback of volumetric rendering-based methods). This significantly limits the application of current scene reconstruction techniques and HDR view synthesis. Enabling real-time rendering for HDR view synthesis is a key step towards bringing computational photography to 3D world.

Recently, 3D Gaussian Splatting (3DGS) has garnered significant attention based on its powerful capabilities in real-time rendering and photorealistic reconstruction. 3DGS utilizes Structure from Motion (SfM) [31] for initialization and employs a set of 3D gaussian primitives to represent the scene. Each gaussian represents direction-aware colors using spherical harmonics (SH) functions and can be updated in terms of color, position, scale, rotation, and opacities through gradient descent optimization. Although 3DGS demonstrates its strong capabilities in reconstruction and real-time rendering, it is not suitable for direct training using nighttime RAW data. This is primarily due to

- 1) the SfM estimations based on nighttime images are often inaccurate, leading to blurred distant views or the potential emergence of floaters; 2) the SH does not adequately represent the HDR color information of RAW images due to its limited representation capacity; and 3) the finally reconstructed structure, such as depth map, is suboptimal, leading to unsatisfactory performance in downstream tasks like refocus.

To make 3DGS suitable for HDR scene reconstruction, we introduce LE3D that stands for Lighting Every darkness with 3D-GS, addressing the three aforementioned issues. First, to address the issue of inaccurate SfM distant view estimation in low-light scenes, we proposed Cone Scatter Initialization to enrich the COLMAP-estimated SfM. It performs random point sampling within a cone using the estimated camera poses. Second, instead of the SH, we use a tiny MLP to represent the color in RAW linear color space. To better initialize the color of each gaussian, different color biases are used for various gaussian primitives. Thirdly, we propose to use depth distortion and near-far regularization to achieve better scene structure for downstream task like refocusing. As shown in Fig. 1 (left), our LE3D can perform real-time rendering with only about 1.5 GPU hours (99% less than RawNeRF [28]) of training time and at a rate of 100 FPS (about 4000× faster than RawNeRF [28]) with comparable quality. Additionally, it is capable of supporting downstream tasks such as HDR rendering, refocusing, and exposure variation, as shown in Fig. 1 (right).

In summary, we make the following contributions:

- • We propose LE3D, which can reconstruct HDR 3D scenes from noisy raw images and perform real-time rendering. Compared with the NeRF-based methods, LE3D requires only 1% of the training time and has 4000× render speed.
- • To address the deficiencies in color representation by vanilla 3DGS and the inadequacies of SfM estimation in nighttime scenes, we leverage a Color MLP with primitive-aware bias, and introduce Cone Scatter Initialization to enrich the point cloud initialized by COLMAP.
- • To improve the scene structure in the final results for achieving better downstream task performance, we introduce depth distortion and near-far regularizations.

### 2 Related work

Novel view synthesis Since the emergence of NeRF [29], NVS has gained significant advancement. NeRF employs an MLP to represent both the geometry of the scene and the view-dependent color. It utilizes the differentiable volume rendering [22], thereby enabling gradient-descent training through a multi-view set of 2D images. Subsequent variants of NeRF [1, 2, 16] have extended NeRF’s capabilities with anti-aliasing features. To overcome the deficiencies of vanilla NeRF in geometry reconstruction, strategies such as depth supervision [9, 7] and distortion loss [2] have been introduced into NeRF. Some methods [11, 3, 30, 5] have conducted experiments with feature-grid based approaches to enhance the training and rendering speeds of NeRF. Although these methods have achieved relatively promising results in novel view synthesis, the training and rendering speeds are still significant bottlenecks. This issue is primarily due to the dense sampling inherently required by volume rendering.

Recently, the advent of 3D Gaussian Splatting [19] has marked a significant advancement in real-time NVS methods. 3DGS represents a scene using a collection of 3D gaussian primitives, each endowed with distinct attributes. Some subsequent works have added anti-aliasing capabilities to 3DGS representations [36, 32, 25]; others have enhanced 3DGS representation capabilities through supervision in the frequency domain [37]. DNGaussian [23] proposed a depth-regularized framework to optimize sparse-view 3DGS, and other works also relying on depth supervision [6, 21]. Additionally, some works [24, 35, 27] have focused on applying 3DGS to dynamic scene representation. However, these methods only accept LDR sRGB data for training, and thus cannot reconstruct the scene’s HDR radiance. This limitation suggests they cannot perform downstream tasks such as HDR tone mapping and exposure variation. In contrast, LE3D is specifically designed to reconstruct the HDR representation of scenes from noisy RAW images.

HDR view synthesis and its applications HDR typically refers to a concept in computational photography that focuses on preserving as much dynamic range as possible to facilitate more post-processing options [8, 10, 26, 18, 15]. The existing HDR view synthesis techniques bear a striking resemblance to the two main approaches in 2D image HDR synthesis: 1) Direct use of multiple-exposure LDR images to compute the camera response function (CRF) and synthesize an HDR image [8]. This corresponds to HDR-NeRF [17] which employs an MLP to learn the CRF. 2) Acquisition of noise-free underexposed RAW images, utilizing the characteristics of the linear color space in RAW to manually simulate multiple-exposure images, and synthesize an HDR image. This corresponds to RawNeRF [28], which learns a NeRF representation of RAW linear color space with noisy RAW images to perform both denoising and NVS. Although both methods achieve impressive visual results, the dense sampling required by volume rendering still poses a bottleneck for both training time and rendering efficiency. LE3D follows the same technical approach as RawNeRF, reconstructing scene representations from noisy RAW images. This means that LE3D does not necessarily require training data with multiple exposures, significantly broadening its range of applications. However, a key distinction of LE3D is its use of differentiable rasterization techniques [19, 20, 33], which enable fast training and real-time rendering. Based on a 3DGS-like representation of the reconstructed scene, LE3D can perform real-time HDR view synthesis. This is a novel attempt to introduce computational photography into 3D world, as it enables real-time reframing and post-processing (changing white balance, HDR rendering, etc. as shown in Fig. 1).

### 3 Preliminaries

- 3D Gaussian Splatting 3D Gaussian Splatting renders detailed scenes by computing the color and depth of pixels through the blending of many 3D gaussian primitives. Each gaussian is defined by its center in 3D space µi ∈ R3, a scaling factor si ∈ R3, a rotation quaternion qi ∈ R4, and additional attributes such as opacity oi and color features fi. The basis function of a gaussian primitive is given by Eqn. (1) that incorporates the covariance matrix derived from the scaling and rotation parameters.

- 1

- 2

(x − µ)TΣ−1(x − µ)). (1)

G(x) = exp(−

During rendering, the color of a pixel is determined by blending the contributions of multiple gaussians that overlap the pixel’s location. This process involves decoding the color features fi to color ci by the SH, and calculating αi of each primitive by multiplied its opacity oi with its projected

[Figure 11]

[Figure 12]

[Figure 13]

[Figure 14]

[Figure 15]

[Figure 16]

[Figure 17]

[Figure 18]

[Figure 19]

Rendered RAW

Noisy RAW

𝑣 Ϝ + Color MLP

[Figure 20]

[Figure 21]

[Figure 22]

[Figure 23]

[Figure 24]

[Figure 25]

|𝑐|
|---|

[Figure 26]

[Figure 27]

[Figure 28]

[Figure 29]

|𝑓| |
|---|---|
| | |

COLMAP Init.

||𝑟|
|---|
<br><br>|𝑜|
|---|
<br><br>|𝑠|
|---|
<br><br>|𝑝|
|---|
|
|---|

| | |
|---|---|
|𝑏| |

ℒ

[Figure 30]

[Figure 31]

[Figure 32]

[Figure 33]

Cone Scatter Init.

[Figure 34]

[Figure 35]

[Figure 36]

[Figure 37]

Noisy Images

After ISP

After ISP

[Figure 38]

[Figure 39]

#### ℛ

[Figure 40]

[Figure 41]

H

[Figure 42]

[Figure 43]

[Figure 44]

[Figure 45]

[Figure 46]

[Figure 47]

ray

[Figure 48]

[Figure 49]

[Figure 50]

|[Figure 51]<br><br>[Figure 52]|[Figure 53]|[Figure 54]<br><br>[Figure 55]| |
|---|---|---|---|
| | | |[Figure 56]|

[Figure 57]

ray

F

3D-GS Init. Training

ℛ

: Rendering Termination

- Figure 2: Pipeline of our proposed LE3D. 1) Using COLMAP to obtain the initial point cloud and camera poses. 2) Employing Cone Scatter Initialization to enrich the point clouds of distant scenes. 3) The standard 3DGS training, where we replace the original SH with our tiny Color MLP to represent the RAW linear color space. 4) We use RawNeRF’s weighted L2 loss L (Eqn. (3)) as image-level supervision, and our proposed Rdist (Eqn. (8)) as well as Rnf (Eqn. (9)) as scene structure regularizations. In this context, fi, bi, and ci respectively represent the color feature, bias, and final rendered color of each gaussian i. Similarly, oi, ri, si, and pi denote the opacity, rotation, scale, and position of them.

- 2D gaussian G2iD on the image plane. Unlike traditional ray sampling strategies, 3D Gaussian Splatting employs an optimized rasterizer to gather the relevant gaussians for rendering. Specifically, the color C is computed by blending N ordered gaussians overlapping the pixel:

- i−1
- j=1

(1 − αj),where αi = G2iDoi. (2)

ci · αi

###### C =

i∈N

HDR view synthesis with noisy RAW images RawNeRF [28], as a powerful extension of NeRF, specifically addresses the challenge of high dynamic range (HDR) view synthesis with noisy images. Different from LDR images, the dynamic range in HDR images can span several orders of magnitude between bright and dark regions, resulting in the NeRF’s standard L2 loss being inadequate. To address this challenge, RawNeRF introduces a weighted L2 loss that enhances supervision in the dark regions. RawNeRF applies gradient supervision on tone curve ψ = log(y + ϵ) with ϵ = 10−3, and uses ψ′ = (y + ϵ)−1 as the weighting term on the L2 loss between rendered color yˆi and noisy reference color yi. Applying the stop-gradient function sg(·) on y, the final loss can be expressed as:

yˆi − yi sg(ˆyi) + ϵ

)2. (3)

Lψ(ˆy,y) =

(

i

Moreover, RawNeRF employs a variable exposure training method to take advantage of images with varying shutter speeds. The method scales the output color in linear RGB space by a learned factor βtc

for each color channel c with each unique shutter speed ti. In particular, the c-th channel of the output color yˆic will be mapped into min(ˆyic · ti · βtc

i

,1) as the final output for rendering.

i

### 4 Proposed method

The pipeline of our LE3D is shown in Fig. 2. Our main motivations and solutions are as follows:

- 1) To address the issue of COLMAP’s inadequacy in capturing distant scenes during nighttime, we utilize the proposed Cone Scatter Initialization to enrich the point cloud obtained from COLMAP.
- 2) Experiments show that the original SH in 3DGS is inadequate for representing the RAW linear color space (as shown in Fig. 4 (e) and Fig. 7). Therefore, we replace it with a tiny color MLP. 3) To enhance the scene structure and optimize the performance of downstream tasks, we propose the depth distortion Rdist and near-far Rnf regularizations.

##### 4.1 Improvements to the vanilla 3DGS representation

Directly applying 3DGS on noisy RAW image set faces aforementioned two challenges, lack of distant points and inadequate representation of RAW linear color space. To address them, we propose the following improvements to the vanilla 3DGS representation.

Cone Scatter Initialization To enrich the COLMAP-initialized point cloud S = {si} with distant scenes, we estimate the position and orientation of all cameras. Based on this, we randomly scatter points within a predefined viewing frustum F. To define F, we need to determine: 1) The viewpoint p; 2) The viewing direction ⃗n; 3) The field of view Θ; and 4) The near and far planes, z = zn and z = zf, respectively. For forward-facing scenes, the viewing direction can be easily determined by averaging the orientations of all cameras, represented as ⃗n = avg{⃗nci}. To encompass all visible areas in space from the training viewpoints, we use the maximum value of FOV from all cameras, denoted as Θ = max{θic}. Additionally, F needs to include all the camera origins {pci} to ensure complete coverage of the scene from all perspectives. It means that F should encompass a circle with its center at pc = avg{pci}, radius r = max{∥pci − pc∥2}, and perpendicular to ⃗n. Therefore, we can establish F:

⃗n ∥⃗n∥2

r tan(Θ/2) ·

p = pc −

, ⃗n = avg{⃗nci}, Θ = max{θic}, zn = min{∥si − p∥2}, zf = λF · max{∥si − p∥2}.

(4)

For near zn and far zf, we use the distance from the nearest and λF times the distance from farthest points in the COLMAP-initialized point cloud S to p to represent them, respectively. Subsequently,

we randomly scatter points within our viewing frustum F = {p,⃗n,Θ,zn,zf} to obtain our enriched point cloud S′ = S ∪ SF, where SF is the scattered point set. Then S′ is used for initialization of the gaussians, instead of S.

Color MLP with primitive-aware bias To address the issue that SH could not adequately represent the RAW linear color space, we replace it with a tiny color MLP Fθ. Each gaussian is initialized with a random color feature fi and a color bias bi. To initialize bi, we project each s′i ∈ S′ onto every training image, obtaining a set of all pixels {cpix}i for each point i,. The color feature fi is concatented with the camera pose v, and then it is feeded into the tiny color MLP Fθ to obtain the view dependent color. Since the HDR color space theoretically has no upper bound on color values, we use the exponent function as the activation function for Fθ to simulate it. The final color ci is:

ci = exp(Fθ(fi,v) + bi),where b(0)i = log(avg({cpix}i)),fi(0) ← N(0,σf). (5)

where fi(0) is sampled from a gaussian distribution N(0,σf) and b(0)i is setted by the log value of the average of {cpix}i. This initialization makes c(0)i close to avg{cpix}i. Both fi and bi are learnable parameters and during cloning and splitting, they are copied and assigned to new gaussians.

##### 4.2 Depth distortion & near-far regularizations

Scene structure is crucially important for the downstream applications of our framework, particularly the tasks such as refocusing. Therefore, we propose depth distortion and near-far regularizations to enhance the ability of 3DGS for optimizing scene structure. Borrow from NeRF-based methods [2], we use depth map and weight map to regularize the scene structure.

Depth and weight map rendering Recently, several 3DGS-based works [23, 6] employ some form of supervision on depth. Also, depth maps are crucial for downstream tasks such as refocus (Sec. 6), mech extraction [14] and relighting [12, 38]. They are achieved by obtaining the rendered average depth map d in the following manner:

zicωi i ωi

, where [xci,yic,zic]T = W[xi,yi,zi]T + t, and ωi = αi

d = i

- i−1
- j=1

(1 − αj). (6)

where d denotes the depth map, ωi represents the blending weight of the i-th gaussian, [xi,yi,zi]T

and [xci,yic,zic]T represent the position in the world and the camera coordinate system, respectively, and [W,t] corresponds to the camera extrinsics. The pixel values in the Weight Map each describe a

histogram H of the distribution on the ray passing through this pixel. Similar to Mip-NeRF 360 [2],

we can optimize the scene structure by constraining the gaussian primitives on each ray to be more concentrated. To obtain the Weight Map, we first need to determine the distances to the nearest and farthest gaussian primitives from the current camera pose pc, represented as znc,zfc, respectively. Subsequently, we transform the interval [znc,zfc) to obtain K intersections, where the k-th intersection is denoted as [tk,tk+1). Thus, the k-th value in the histogram H(k) can be obtained through rendering in the following manner:

1 if zic ∈ [tk,tk+1) 0 else

1(zic,k)ωi, where 1(zic,k) =

. (7)

H(k) =

i

Rendering H is essential, as it is effective not only in regularization but also plays a role in the refocusing application.

Proposed regularizations Inspired by Mip-NeRF 360 [2], we proposed similar depth distortion regularization Rdist to concentrate the gaussians on each ray:

K

tu + tu+1 2 −

tv + tv+1 2

. (8)

Rdist =

H(u)H(v)

u,v

Rdist constrains the weights along the entire ray to either approach zero or be concentrated at the same intersection. However, in unbounded scenes of the real world, the distances (zfc − znc)/K between each intersection are vast. Forcibly increasing the size of K to reduce the length of each intersection also significantly increases the computational burden. This means that our Rdist can only provide a relatively coarse supervision for the gaussians on each ray, primarily by constraining them as much as possible within the same intersection.

To further constrain the concentration of gaussians, we propose the Near-Far Regularization Rnf. Rnf enhances the optimization of scene structure by narrowing the distance between the weighted depth of the nearest and farthest M gaussians on each ray, where the farthest refers to the last M gaussians when the blending weight approaches 1. First, we extract two subsets of gaussians, N and F, which respectively contain the nearest and farthest M gaussians on each ray. Subsequently, we render the depth maps for both subsets (dN, dF), as well as the final blending weight map (TN, TF). The blending weight map T is the sum of each ωi. And here comes Rnf:

Rnf = TN · TF · dN − dF . (9) It not only can prune the gaussians at the front or back of each ray through opacity supervision when there is a significant disparity between them (relying on the TN · TF term). Compared to Rdist, Rnf can also supervise the position of the first and last M gaussians on each ray to be as close as possible (relying on the dN − dF term). Besides the weighted L2 loss L and proposed regularizations Rdist and Rnf, we also introduce constraints on the final blending weights T. Given that the LE3D is tested in real-world scenarios, T should ideally approach 1, meaning that all pixels should be rendered. Thus, we propose RT = −log(T + ϵ) to penalize the pixels where T is less than 1.

### 5 Experiments

##### 5.1 Implementation details

Loss functions and regularizations In our implementation, the final loss function is:

L = L + λTRT + λdistRdist + λnfRnf, (10)

where L is the weighted L2 loss, and RT, Rdist, and Rnf are the proposed T, depth distortion, and near-far regularizations, respectively.

Optimization We set λF to 10 to enrich the COLMAP-initialized point cloud in distant views. λT,λdist,λnf in the loss function are set to 0.01,0.1,0.01 respectively. For our color MLP Fθ, we use the Adam optimizer with an initial learning rate of 1.0e − 4. The initial learning rates for color features and biases for each gaussians are set to 2.0e − 3 and 1.0e − 4, respectively. The learning rates for all three decrease according to a cosine decay strategy to a final learning rate of 1.0e − 5. Besides the color MLP, primitive-aware color bias, and the color features for each gaussians, other settings are the same as those of 3DGS [19]. For scenes captured with multiple exposures, we employ the same multiple exposure training strategy as RawNeRF [28].

- Table 1: Quantitative results on the test scenes of the RawNeRF [28] dataset. The best result is in bold whereas the second best one is in underlined. TM indicates whether the tone-mapping function can be replaced for HDR rendering. For methods where the tone-mapping function can be replaced, the metrics on sRGB are calculated using LDR tone-mapping for a fair comparison. The FPS measurement is conducted at a 2K (2016×1512) resolution. Train denotes the training time of the method, measured in GPU×H. LE3D achieves comparable performance with previous volumetric rendering based methods (RawNeRF [28]), but with 4000× faster rendering speed.

RAW sRGB PSNR↑ SSIM↑ PSNR↑ SSIM↑ LPIPS↓

Method TM FPS↑ Train↓

LDR-NeRF [29] ✗ 0.007 13.66 − − 20.0391 0.5541 0.5669 LDR-3DGS [19] ✗ 153 0.75 − − 20.2936 0.5477 0.5344

HDR-3DGS [19] ✓ 238 0.73 56.4960 0.9926 20.3320 0.5286 0.6563

RawNeRF [28] ✓ 0.022 129.54 58.6920 0.9969 24.0836 0.6100 0.4952 RawGS (Baseline) ✓ 176 1.05 59.2834 0.9971 23.3485 0.5843 0.5472

LE3D (Ours) ✓ 103 1.53 61.0812 0.9983 24.6984 0.6076 0.5071

- 5.2 Datasets and comparisons

Datasets We evaluated LE3D’s performance on the benchmark dataset of RawNeRF. It includes fourteen scenes for qualitative testing and three test scenes for quantitative testing. The three test scenes, each contains 101 noisy images and a clean reference image merged from stabilized long exposures. However, the training data are captured with short exposures, leading to exposure inconsistencies. Therefore, we apply the same affine alignment operation as RawNeRF before testing (detailed in Sec. A.1 of the supplementary materials). All images are 4032 × 3024 Bayer RAW images captured by an iPhone X, saved in DNG format.

Baseline and comparative methods We compare two categories of methods, 3DGS-based methods and NeRF-based methods. The baseline we compare against is RawGS which uses vanilla 3DGS for scene representation and employs the weighted L2 loss and multiple exposure training proposed in RawNeRF [28]. Additionally, we compare LDR-GS and HDR-GS, both of which are vanilla 3DGS trained on post-processed LDR images and unprocessed RAW images, respectively. The NeRF-based methods include RawNeRF [28] and LDR-NeRF. RawNeRF is a Mip-NeRF [1] directly trained on noisy RAW images with weighted L2 loss and multi-exposure training strategy. LDR-NeRF is a vanilla NeRF [29] trained on the post-processed LDR images with L2 loss.

Quantitative evaluation Tab. 1 has shown the quantitative comparisons on the RawNeRF [28] dataset. Although NeRF-based methods have long training times and slow rendering speeds, they exhibit good metrics on sRGB. This indicates that the volume rendering they rely on has strong noise resistance (mainly due to the dense sampling on each ray). In contrast, 3DGS-based methods have inferior metrics compared to RawNeRF, due to their sparse scene representation and poor noise resistance. Additionally, the splitting of gaussians depends on gradient strength, and supervision using noisy raw images affects this process, leading to incomplete structure recovery. LE3D achieves better structure reconstruction suitable for downstream tasks through supervision on structure, depth distortion, and near-far regularizations, as detailed in Sec. 6. Note that the results of LE3D are comparable to the previous volumetric rendering-based method, RawNeRF [28], in both quantitative and qualitative aspects. However, it requires only 1% of the training time and achieves a 3000×6000× rendering speed improvement.

Qualitative evaluation Fig. 3 has shown the qualitative comparisons on the RawNeRF [28] dataset. We selected four scenes for comparison, including two indoor scenes and two outdoor scenes. The data for the first two scenes were collected with a single exposure, while the data for the latter two scenes included multiple exposures. Compared to 3DGS [19]-based methods, LE3D demonstrates stronger noise resistance, particularly in the first two scenes. Additionally, LE3D achieves better results in distant scene reconstruction. For example, in the second scene, LE3D produces a smoother sky compared to RawGS, and in the fourth scene, LE3D recovers distant details more sharply. Compared to RawNeRF, LE3D typically produces smoother results while still effectively preserving details. Most importantly, LE3D offers faster training times and rendering speeds.

Training View LDR-NeRF [29] LDR-GS [19] RawNeRF [28] RawGS (Baseline) LE3D (Ours)

|[Figure 58]|[Figure 59]<br><br>FPS: 0.007|[Figure 60]<br><br>FPS: 186.6|[Figure 61]<br><br>FPS: 0.023|[Figure 62]<br><br>FPS: 225.7|[Figure 63]<br><br>FPS: 137.9|
|---|---|---|---|---|---|
|[Figure 64]|[Figure 65]<br><br>FPS: 0.007|[Figure 66]<br><br>FPS: 256.0|[Figure 67]<br><br>FPS: 0.023|[Figure 68]<br><br>FPS: 137.1|[Figure 69]<br><br>FPS: 110.4|
|[Figure 70]|[Figure 71]<br><br>FPS: 0.007|[Figure 72]<br><br>FPS: 219.6|[Figure 73]<br><br>FPS: 0.023|[Figure 74]<br><br>FPS: 204.5|[Figure 75]<br><br>FPS: 87.4|
|[Figure 76]|[Figure 77]<br><br>FPS: 0.007|[Figure 78]<br><br>FPS: 128.4|[Figure 79]<br><br>FPS: 0.023|[Figure 80]<br><br>FPS: 135.8|[Figure 81]<br><br>FPS: 80.7|

- Figure 3: Visual comparison between LE3D and other reconstruction methods (Zoom-in for best view). The training view contains two parts: the post-processed RAW image with linear brightness enhancement (up) and the image directly output by the device (down). By comparison to the 3DGSbased method, LE3D recovers sharper details in the distant scene and is more resistant to noise. Additionally, compared to NeRF-based methods, LE3D achieves comparable results with 3000×6000× improvement in rendering speed.

##### 5.3 Ablation studies

Cone Scatter Initialization (CSI) In low-light environments, COLMAP struggles to obtain a high-quality sparse point cloud. Although 3DGS demonstrates its robustness to the quality of the initial point cloud, it still encounters difficulties in achieving optimal geometric reconstruction within insufficient initialized areas. It can be observed from Fig. 4 (b) that the methods without CSI tend to generate gaussians at incorrect depths and lack fine details. Conversely, CSI extends the depth coverage of the scene, enabling 3DGS to generate gaussians at relatively accurate depths and exhibit superior detail representation. A comparative analysis between Fig. 4 (a) and Fig. 4 (b) suggests that our initialization technique plays a pivotal role in achieving accurate and detailed 3D reconstruction.

Color MLP Replacing SH with Color MLP not only enhances the expressiveness of our model but also introduces greater stability during the optimization process. Fig. 4 (e) reveals that the method employing SH rather than Color MLP exhibits strange color representations early in the training phase, due to the inability of SH to adequately represent the RAW linear color space. Although the rendered image may appear similar to those produced by the LE3D, the underlying issues have significantly affected the final structural reconstruction, as depicted in Fig. 4 (c).

Regularizations Superior visual effects in 3D are contingent upon a robust 3D structure reconstruction, which in turn significantly enhances the performance of downstream tasks such as refocusing. To this end, we implement depth distortion regularization Rdist and near-far regularization Rnf to constrain the gaussians, ensuring their aggregation at the surfaces of objects and thereby improving the quality of structural reconstruction. Fig. 4 (d) underscores the substantial enhancement our proposed regularizations provide in reconstructing the 3D structure of scenes.

### 6 More applications

Refocus Structural information is crucial for tasks like refocusing. As discussed in Sec. 5.3, LE3D benefits from the inclusion of depth distortion and near-far regularizations, which enhances its ability to learn structural details. As shown in Fig. 5 (b, d), LE3D achieves more realistic refocusing effects due to its superior structural information, as reflected in the depth shown in (c). Conversely, RawGS suffers from foreground and background ambiguity in refocusing due to the lack of structural information. Detailed refocusing algorithm will be released in the supplementary materials.

[Figure 82]

[Figure 83]

[Figure 84]

[Figure 85]

[Figure 86]

[Figure 87]

w/ Color MLP

[Figure 88]

[Figure 89]

[Figure 90]

[Figure 91]

[Figure 92]

[Figure 93]

w/o Color MLP

Training View (a) LE3D (b) w/o CSI (c) w/o Color MLP (d) w/o Regs (e) Results at 7k iter

- Figure 4: Ablation studies on our purposed methods (Zoom-in for best view). CSI in (b) and Regs in (d) denote Cone Scatter Initialization and Regularizations, respectively. (e) shows the rendering result of LE3D w/ or w/o Color MLP in early stages of training.

(f) Exposure Variation

[Figure 94]

[Figure 95]

[Figure 96]

| |
|---|

[Figure 97]

| |
|---|

[Figure 98]

Focus at here

[Figure 99]

[Figure 100]

[Figure 101]

Focus at here

[Figure 102]

| |
|---|

[Figure 103]

| |
|---|

(a) LE3D output (b) LE3D refocus (c) LE3D output depth (d) RawGS refocus (e) RawGS output depth

[Figure 104]

[Figure 105]

[Figure 106]

[Figure 107]

[Figure 108]

[Figure 109]

Long

Medium

Short

[Figure 110]

[Figure 111]

[Figure 112]

[Figure 113]

[Figure 114]

[Figure 115]

[Figure 116]

(g) Changing Tone-mapping, Viewpoint, and Focus

Global & Local Tone-mapping

More Results

⋆

- Figure 5: LE3D supports various applications. RawGS⋆ in (d) denotes using LE3D’s rendered image and RawGS’s structure information as input for refocusing. (c, e) are the weighted depth rendered by LE3D and RawGS, respectively. (f) shows the same scene rendered by LE3D with different exposure settings. In (g), the “→” denotes global tone-mapping, while the “→” represents local tone-mapping.

Exposure variation and HDR tone-mapping LE3D can easily achieve exposure variation and recover details from overexposed data, as shown in Fig. 5 (f). Fig. 5 (g) showcases the various tone-mapping methods LE3D can implement, including global tone-mapping, such as color temperature and curve adjustments, and local tone-mapping using our re-implemented HDR+ [15] (implementation details will be released in the supplementary materials).

Although RawNeRF [28] can also perform similar applications, its inability to achieve real-time rendering significantly limits its use cases, such as real-time editing described in Sec. B.

### 7 Conclusion

To address the long training times and slow rendering speeds of previous volumetric rendering-based methods, we propose LE3D based on 3DGS. Additionally, we introduce Cone Scatter Initialization and a tiny MLP for representing color in the linear color space. This addresses the issue of missing distant points in nighttime scenes with COLMAP initialization. It also replaces spherical harmonics with the tiny color MLP, effectively representing the linear color space. Finally, we enhance the structural reconstruction with the proposed depth distortion and near-far regularization, enabling more effective and realistic downstream tasks. Benefiting from the rendering images in the linear color space, LE3D can achieve more realistic exposure variation and HDR tone-mapping in real-time, expanding the possibilities for subsequent HDR view synthesis processing.

### References

- [1] Jonathan T Barron, Ben Mildenhall, Matthew Tancik, Peter Hedman, Ricardo Martin-Brualla, and Pratul P Srinivasan. Mip-nerf: A multiscale representation for anti-aliasing neural radiance fields. In ICCV, 2021.
- [2] Jonathan T Barron, Ben Mildenhall, Dor Verbin, Pratul P Srinivasan, and Peter Hedman. Mip-nerf 360: Unbounded anti-aliased neural radiance fields. In CVPR, 2022.
- [3] Anpei Chen, Zexiang Xu, Andreas Geiger, Jingyi Yu, and Hao Su. Tensorf: Tensorial radiance fields. In ECCV, 2022.
- [4] Chen Chen, Qifeng Chen, Jia Xu, and Vladlen Koltun. Learning to see in the dark. In CVPR, 2018.
- [5] Zhang Chen, Zhong Li, Liangchen Song, Lele Chen, Jingyi Yu, Junsong Yuan, and Yi Xu. Neurbf: A neural fields representation with adaptive radial basis functions. In ICCV, 2023.
- [6] Jaeyoung Chung, Jeongtaek Oh, and Kyoung Mu Lee. Depth-regularized optimization for 3d gaussian splatting in few-shot images. arXiv:2311.13398, 2023.
- [7] David Dadon, Ohad Fried, and Yacov Hel-Or. Ddnerf: Depth distribution neural radiance fields. In WACV, 2023.
- [8] Paul E Debevec and Jitendra Malik. Recovering high dynamic range radiance maps from photographs. Siggraph, 1997.
- [9] Kangle Deng, Andrew Liu, Jun-Yan Zhu, and Deva Ramanan. Depth-supervised nerf: Fewer views and faster training for free. In CVPR, 2022.
- [10] Gabriel Eilertsen, Joel Kronander, Gyorgy Denes, Rafał K Mantiuk, and Jonas Unger. Hdr image reconstruction from a single exposure using deep cnns. ACM TOG, 2017.
- [11] Sara Fridovich-Keil, Alex Yu, Matthew Tancik, Qinhong Chen, Benjamin Recht, and Angjoo Kanazawa. Plenoxels: Radiance fields without neural networks. In CVPR, 2022.
- [12] Jian Gao, Chun Gu, Youtian Lin, Hao Zhu, Xun Cao, Li Zhang, and Yao Yao. Relightable 3d gaussian: Real-time point cloud relighting with brdf decomposition and ray tracing. arXiv:2311.16043, 2023.
- [13] NeRF Studio Group. Viser. https://github.com/nerfstudio-project/viser, 2023.
- [14] Antoine Guédon and Vincent Lepetit. Sugar: Surface-aligned gaussian splatting for efficient 3d mesh reconstruction and high-quality mesh rendering. CVPR, 2024.
- [15] Samuel W Hasinoff, Dillon Sharlet, Ryan Geiss, Andrew Adams, Jonathan T Barron, Florian Kainz, Jiawen Chen, and Marc Levoy. Burst photography for high dynamic range and low-light imaging on mobile cameras. ACM TOG, 2016.
- [16] Wenbo Hu, Yuling Wang, Lin Ma, Bangbang Yang, Lin Gao, Xiao Liu, and Yuewen Ma. Tri-miprf: Tri-mip representation for efficient anti-aliasing neural radiance fields. In ICCV, 2023.
- [17] Xin Huang, Qi Zhang, Ying Feng, Hongdong Li, Xuan Wang, and Qing Wang. Hdr-nerf: High dynamic range neural radiance fields. In CVPR, 2022.
- [18] Nima Khademi Kalantari, Ravi Ramamoorthi, et al. Deep high dynamic range imaging of dynamic scenes. ACM TOG, 2017.
- [19] Bernhard Kerbl, Georgios Kopanas, Thomas Leimkühler, and George Drettakis. 3d gaussian splatting for real-time radiance field rendering. ACM TOG, 2023.
- [20] Georgios Kopanas, Julien Philip, Thomas Leimkühler, and George Drettakis. Point-based neural rendering with per-view optimization. In Computer Graphics Forum, 2021.
- [21] Pou-Chun Kung, Seth Isaacson, Ram Vasudevan, and Katherine A Skinner. Sad-gs: Shape-aligned depth-supervised gaussian splatting. In ICRA Workshops, 2024.
- [22] Marc Levoy. Efficient ray tracing of volume data. ACM TOG, 1990.
- [23] Jiahe Li, Jiawei Zhang, Xiao Bai, Jin Zheng, Xin Ning, Jun Zhou, and Lin Gu. Dngaussian: Optimizing sparse-view 3d gaussian radiance fields with global-local depth normalization. arXiv:2403.06912, 2024.
- [24] Zhan Li, Zhang Chen, Zhong Li, and Yi Xu. Spacetime gaussian feature splatting for real-time dynamic view synthesis. CVPR, 2024.
- [25] Zhihao Liang, Qi Zhang, Wenbo Hu, Ying Feng, Lei Zhu, and Kui Jia. Analytic-splatting: Anti-aliased 3d gaussian splatting via analytic integration. arXiv:2403.11056, 2024.
- [26] Yu-Lun Liu, Wei-Sheng Lai, Yu-Sheng Chen, Yi-Lung Kao, Ming-Hsuan Yang, Yung-Yu Chuang, and Jia-Bin Huang. Single-image hdr reconstruction by learning to reverse the camera pipeline. In CVPR, 2020.
- [27] Jonathon Luiten, Georgios Kopanas, Bastian Leibe, and Deva Ramanan. Dynamic 3d gaussians: Tracking by persistent dynamic view synthesis. arXiv:2308.09713, 2023.

- [28] Ben Mildenhall, Peter Hedman, Ricardo Martin-Brualla, Pratul P Srinivasan, and Jonathan T Barron. Nerf in the dark: High dynamic range view synthesis from noisy raw images. In CVPR, 2022.
- [29] Ben Mildenhall, Pratul P Srinivasan, Matthew Tancik, Jonathan T Barron, Ravi Ramamoorthi, and Ren Ng. Nerf: Representing scenes as neural radiance fields for view synthesis. In ECCV, 2020.
- [30] Thomas Müller, Alex Evans, Christoph Schied, and Alexander Keller. Instant neural graphics primitives with a multiresolution hash encoding. ACM TOG, 2022.
- [31] Johannes Lutz Schönberger and Jan-Michael Frahm. Structure-from-motion revisited. In CVPR, 2016.
- [32] Xiaowei Song, Jv Zheng, Shiran Yuan, Huan-ang Gao, Jingwei Zhao, Xiang He, Weihao Gu, and Hao Zhao. Sa-gs: Scale-adaptive gaussian splatting for training-free anti-aliasing. arXiv:2403.19615, 2024.
- [33] Cheng Sun, Min Sun, and Hwann-Tzong Chen. Direct voxel grid optimization: Super-fast convergence for radiance fields reconstruction. In CVPR, 2022.
- [34] Kaixuan Wei, Ying Fu, Yinqiang Zheng, and Jiaolong Yang. Physics-based noise modeling for extreme low-light photography. IEEE TPAMI, 2021.
- [35] Guanjun Wu, Taoran Yi, Jiemin Fang, Lingxi Xie, Xiaopeng Zhang, Wei Wei, Wenyu Liu, Qi Tian, and Xinggang Wang. 4d gaussian splatting for real-time dynamic scene rendering. arXiv:2310.08528, 2023.
- [36] Zehao Yu, Anpei Chen, Binbin Huang, Torsten Sattler, and Andreas Geiger. Mip-splatting: Alias-free 3d gaussian splatting. CVPR, 2024.
- [37] Jiahui Zhang, Fangneng Zhan, Muyu Xu, Shijian Lu, and Eric Xing. Fregs: 3d gaussian splatting with progressive frequency regularization. CVPR, 2024.
- [38] Tianyi Zhang, Kaining Huang, Weiming Zhi, and Matthew Johnson-Roberson. Darkgs: Learning neural illumination and 3d gaussians relighting for robotic exploration in the dark. arXiv:2403.10814, 2024.

### A Implementation details and more ablation studies

##### A.1 Affine alignment

Since all training views in the RawNeRF [28] dataset are captured with a fast shutter, while the test views (ground truth) are captured with a slow shutter, linear enhancement is needed during testing for alignment. However, due to color bias (non-zero-mean noise for high ISO, [34]), direct linear enhancement does not achieve perfect alignment. Therefore, affine alignment is performed on both the output and ground truth during testing. In RawNeRF [28], this process is done as the following procedure:

xy − xy x2 − x2

Cov(x,y) Var(x)

,b = y − ax. (11)

a =

=

where x is the mean of x. And x,y are the groundtruth and the final output, respectively. This is the least-squares fit of an affine transform ax + b ≈ y. At test time, we first process y with (y − b)/a, then calculate the metric. For those methods whose output is in RAW linear color space, the affine alignment process is only done once in the RAW color space. While for other methods (LDR-NeRF [29], LDR-3DGS [19]) which can only output in RGB color space, the affine alignment process is done in the RGB color space.

##### A.2 More ablation studies

Ablation on each of the regularizations Fig. 6 (a,b) presents the visualization of dN and dF adjacent to the depth map. In an ideal scenario, both dN and dF should align with d, ensuring that the weights along each ray are concentrated at surface. The comparison between Fig. 6 (a,b) demonstrates that the incorporation of near-far regularization indeed encourages dN and dF to progressively align with d. This alignment results in a more refined representation of the three-dimensional structure, capturing better details of the scene’s geometry. The comparison between Fig. 6 (a,c) elucidates the adverse effects of omitting distortion regularization. Without such constraints, the model would fail to produce depth maps with a natural depth progression, with artifacts such as abrupt depth discontinuities or voids on planes. Such anomalies are indicative of significant issues in the reconstruction of the scene’s geometry.

- Table 2: Quantitative results of the ablation studies. Notice that, since Cone Scatter Initialization (CSI) is used to supplement the point cloud in distant scenes, and the test scenes do not contain distant views (all being indoor scenes), LE3D does not apply CSI in this context. The ablation study of CSI can be found in Fig. 4 (a, b), which shows significant differences in distant view. Best results is denoted in bold. The rank is indicated in the lower right corner of each metrics.

RAW sRGB PSNR↑ SSIM↑ PSNR↑ SSIM↑ LPIPS↓

Method

w/o Color MLP 59.4483(4) 0.9969(4) 23.1884(4) 0.5862(4) 0.5635(4) w/o Rdist 60.5202(3) 0.9981(3) 24.3615(3) 0.6007(3) 0.5087(2)

w/o Rnf 60.7144(2) 0.9982(2) 24.5705(2) 0.6043(2) 0.5096(3) LE3D (Ours) 61.0812(1) 0.9983(1) 24.6984(1) 0.6077(1) 0.5071(1)

[Figure 117]

[Figure 118]

[Figure 119]

[Figure 120]

[Figure 121]

𝑑𝐍 𝑑𝐅

𝑑 𝑑

LE3D Results (a) LE3D, 𝑑 ≈ 𝑑𝐍 ≈ 𝑑𝐅

(c) w/o ℛ

[Figure 122]

[Figure 123]

[Figure 124]

[Figure 125]

𝑑𝐍 𝑑𝐅

𝑑 𝑑

(b) w/o ℛ , 𝑑 ≠ 𝑑𝐍 ≠ 𝑑𝐅

Training View (d) w/o ℛ ,ℛ

- Figure 6: Ablation on each of the regularization. Since both Rdist and Rnf are regularization terms intended to strengthen the structural representation, we have elected to display only the depth map for the sake of clarity. In addition, to demonstrate the effect of Rnf in aligning d,dN,dF, we have also visualized dN and dF as mentioned in Sec. 4.2.

Ablation studies on test scenes As shown in Tab. 2, LE3D has shown superior performance over all ablated methods. The results without Color MLP are the worst because the SH used in vanilla

- 3DGS is not suitable for representing colors in the RAW linear color space. As shown in Fig. 7, the

results without Color MLP are noticeably desaturated and appear gray. Both w/o Rnf and w/o Rdist show degraded depth, as seen in Fig. 7. Additionally, it can be observed that w/o Color MLP also has poor structural information. This is mainly due to instability during the early stages of training, leading to suboptimal depth map reconstruction, as discussed in Sec. 5.3.

The stability of LE3D Due to the random initialization of our Color MLP, we trained 9 versions of LE3D using 9 different random seeds to test the stability of LE3D. We then compared their metrics on the test set, as shown in Fig. 8. It can be observed that the stability of LE3D is remarkably high, and the overall fluctuations do not impact the experimental conclusions.

### B Interactive viewer

Fig. 9 has shown some screenshots and downstream tasks results of our interactive viewer which is built upon Viser [13]. Besides refocusing, most of the downstream tasks can be performed in real-time. While for refocusing, most of the time is spent on the gaussian blur according to the refocusing algorithm (due to the large gaussian blur kernel size) rather than on rendering.

LE3D (Ours) w/o Color MLP w/o ℛ w/o ℛ

[Figure 126]

[Figure 127]

[Figure 128]

[Figure 129]

[Figure 130]

RenderedImageRenderedDepth

GroundTruth*TrainingView

|[Figure 131]|
|---|

|[Figure 132]|
|---|

[Figure 133]

[Figure 134]

[Figure 135]

[Figure 136]

[Figure 137]

|[Figure 138]|
|---|

|[Figure 139]|
|---|

- Figure 7: Visualization results for ablation studies on the test scene. The Ground Truth denotes the raw image averaged from a burst set with slow shutter to perform denoising. It can be observed that the results of w/o Color MLP show significant color degradation, while the results of w/o Rnf and w/o Rdist exhibit structural degradation.

###### RAW PSNR↑

- 0.9982

- 0.9983

- 0.9984 RAW SSIM↑

###### 24.70 RGB PSNR↑

###### RGB SSIM↑

###### 0.508 RGB LPIPS↓

61.20

0.610

61.00

24.65

0.506

0.609

60.80

0.608

LE3D Mean RawNeRF

24.60

0.504

Values

59.00

| |
|---|

0.9969

24.10

0.497

0.607

Bootstrap CI

58.75

0.606

0.9968

24.05

0.495

0.605

58.50

0.9967

24.00

0.493

Figure 8: The error bars of our proposed LE3D and comparison with RawNeRF [28].

### C More results

Detailed comparisons between 3DGS-based methods and LE3D As shown in Fig. 10, LE3D achieves better structure reconstruction than our baseline RawGS (3DGS trained with RawNeRF’s loss and multiple exposure training strategy). And compare with LDR-GS (trained on the LDR images) and HDR-GS (trained directly on the RAW data), LE3D achieves better color reconstruction results as well as perform better denoising ability. We also found that LDR-GS and HDR-GS have fewer reconstructed gaussians, resulting in faster rendering speeds but poor overall reconstruction quality. Additionally, LDR-GS, trained on linear brightened LDR images, shows weaker resistance to color bias [34], resulting in severe color shifts in the final output. We also found that the generally low values of RAW images lead to insufficient gradients, reducing the number of gaussian spliting. RawNeRF’s weighted L2 loss (Eqn. (3)) strengthens supervision in dark areas but at the cost of structural information. LE3D incorporates both the weighted L2 loss and depth distortion and near-far regularizations to constrain the structure, ultimately achieving the best structural and visual results.

More qualitative results Fig. 7, Fig. 10, Fig. 11, Fig. 12 has shown more qualitative comparisons between LE3D and 3DGS [19]-based methods. From the figures above, it is evident that LE3D demonstrates superior noise resistance and color representation capabilities. Additionally, LE3D produces smoother and more accurate depth maps, which are essential for downstream tasks like refocusing. It worth noting that volumetric rendering-based methods, such as RawNeRF [28], cannot achieve real-time rendering, which significantly limits their applications (including real-time scene editing). Therefore, we do not compare them here. For comparisons between LE3D and volumetric rendering based methods, please refer to Tab. 1 and Fig. 3.

|[Figure 140]|
|---|

|[Figure 141]|
|---|

|[Figure 142]|
|---|

[Figure 143]

[Figure 144]

[Figure 145]

(c) Exposure Variation, 91.6 FPS

(a) Base View, 91.6 FPS

(b) Render Depth, 64.6 FPS

|[Figure 146]|
|---|

|[Figure 147]|
|---|

|[Figure 148]|
|---|

[Figure 149]

[Figure 150]

[Figure 151]

(d) Refocus, 14.1 FPS

(e) Global & Local (HDR+) TM, 35.1 FPS

(f) Novel View, 116 FPS

- Figure 9: Some screenshots of our interactive viewer, which can perform (b) depth rendering, (c) exposure variation, (d) refocus, (e) global & local tone-mapping and (f) novel view rendering. The FPS are emphasized by the green bounding box, and the changed rendering parameters are emphasized in red bounding box.

LE3D (Ours) RawGS (Baseline) HDR-GS [19] LDR-GS [19]

[Figure 152]

[Figure 153]

[Figure 154]

[Figure 155]

[Figure 156]

RenderedImageRenderedDepth

GroundTruth*TrainingView

[Figure 157]

[Figure 158]

[Figure 159]

[Figure 160]

[Figure 161]

[Figure 162]

[Figure 163]

[Figure 164]

[Figure 165]

[Figure 166]

RenderedImageRenderedDepth

GroundTruth*TrainingView

[Figure 167]

[Figure 168]

[Figure 169]

[Figure 170]

[Figure 171]

[Figure 172]

[Figure 173]

[Figure 174]

[Figure 175]

[Figure 176]

RenderedImageRenderedDepth

GroundTruth*TrainingView

[Figure 177]

[Figure 178]

[Figure 179]

[Figure 180]

[Figure 181]

- Figure 10: Comparison between LE3D and other 3DGS-based methods (Zoom-in for best view). All the results are the direct output of each model, not being applied by affine alignment. The Ground Truth denotes the raw image averaged from a burst set with slow shutter to perform denoising.

[Figure 182]

[Figure 183]

[Figure 184]

[Figure 185]

RenderedImageRenderedDepth

[Figure 186]

[Figure 187]

| |
|---|

TrainingView

[Figure 188]

[Figure 189]

[Figure 190]

[Figure 191]

[Figure 192]

[Figure 193]

[Figure 194]

[Figure 195]

RenderedImageRenderedDepth

TrainingView

[Figure 196]

[Figure 197]

[Figure 198]

[Figure 199]

[Figure 200]

[Figure 201]

[Figure 202]

[Figure 203]

RenderedImageRenderedDepth

TrainingView

[Figure 204]

[Figure 205]

[Figure 206]

[Figure 207]

| |
|---|

| |
|---|

[Figure 208]

[Figure 209]

[Figure 210]

[Figure 211]

[Figure 212]

[Figure 213]

RenderedImageRenderedDepth

TrainingView

[Figure 214]

[Figure 215]

[Figure 216]

[Figure 217]

- Figure 11: Comparison between LE3D and RawGS (baseline, 3DGS trained with weighted L2 loss in Eqn. (3) and multiple exposure strategy). It can be observed that LE3Dexhibits stronger noise resistance and color representation in low-light scenes. Additionally, it produces smoother and more accurate depth maps across all scenes.

[Figure 218]

[Figure 219]

[Figure 220]

[Figure 221]

| |
|---|

| |
|---|

RenderedImageRenderedDepth

|[Figure 222]|
|---|

|[Figure 223]|
|---|

TrainingView

[Figure 224]

[Figure 225]

[Figure 226]

[Figure 227]

[Figure 228]

[Figure 229]

[Figure 230]

[Figure 231]

| |
|---|

| |
|---|

RenderedImageRenderedDepth

|[Figure 232]|
|---|

|[Figure 233]|
|---|

TrainingView

[Figure 234]

[Figure 235]

[Figure 236]

[Figure 237]

[Figure 238]

[Figure 239]

[Figure 240]

[Figure 241]

RenderedImageRenderedDepth

TrainingView

[Figure 242]

[Figure 243]

[Figure 244]

[Figure 245]

|[Figure 246]|
|---|

|[Figure 247]|
|---|

[Figure 248]

[Figure 249]

[Figure 250]

[Figure 251]

| |
|---|

| |
|---|

RenderedImageRenderedDepth

TrainingView

[Figure 252]

[Figure 253]

[Figure 254]

[Figure 255]

- Figure 12: Comparison between LE3D and RawGS (baseline, 3DGS trained with weighted L2 loss in Eqn. (3) and multiple exposure strategy). It can be observed that LE3Dexhibits stronger noise resistance and color representation in low-light scenes. Additionally, it produces smoother and more accurate depth maps across all scenes.

