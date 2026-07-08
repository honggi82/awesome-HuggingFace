# arXiv:2403.08551v5[eess.IV]9Jul2024

## GaussianImage: 1000 FPS Image Representation and Compression by 2D Gaussian Splatting

Xinjie Zhang1,3⋆∔, Xingtong Ge2,3⋆∔, Tongda Xu4, Dailan He5, Yan Wang4, Hongwei Qin3, Guo Lu6, Jing Geng2†, and Jun Zhang1†

- 1 The Hong Kong University of Science and Technology
- 2 Beijing Institute of Technology 3 SenseTime Research

4 Institute for AI Industry Research (AIR), Tsinghua University 5 The Chinese University of Hong Kong 6 Shanghai Jiaotong University

xzhangga@connect.ust.hk, xingtong.ge@gmail.com, x.tongda@nyu.edu hedailan@link.cuhk.edu.hk, wangyan202199@163.com, qinhongwei@sensetime.com

luguo2014@sjtu.edu.cn, janegeng@bit.edu.cn, eejzhang@ust.hk

Abstract. Implicit neural representations (INRs) recently achieved great

success in image representation and compression, offering high visual quality and fast rendering speeds with 10-1000 FPS, assuming sufficient GPU resources are available. However, this requirement often hinders their use on low-end devices with limited memory. In response, we propose a groundbreaking paradigm of image representation and compression by 2D Gaussian Splatting, named GaussianImage. We first introduce 2D Gaussian to represent the image, where each Gaussian has 8 parameters including position, covariance and color. Subsequently, we unveil a novel rendering algorithm based on accumulated summation. Remarkably, our method with a minimum of 3× lower GPU memory usage and 5× faster fitting time not only rivals INRs (e.g., WIRE, INGP) in representation performance, but also delivers a faster rendering speed of 1500-2000 FPS regardless of parameter size. Furthermore, we integrate existing vector quantization technique to build an image codec. Experimental results demonstrate that our codec attains rate-distortion performance comparable to compression-based INRs such as COIN and COIN++, while facilitating decoding speeds of approximately 2000 FPS. Additionally, preliminary proof of concept shows that our codec surpasses COIN and COIN++ in performance when using partial bits-back coding. Code is available at https://github.com/Xinjie-Q/GaussianImage.

Keywords: 2D Gaussian Splatting · Image Representation · Image Compression

### 1 Introduction

Image representation is a fundamental tasks in signal processing and computer vision. Traditional image representation methods, including grid graphics, wavelet

⋆ Equal Contribution. ∔ This work was done when Xinjie Zhang and Xingtong Ge interned at SenseTime Research. † Corresponding Authors.

Kodak Dataset (Representation)

DIV2K Dataset (Compression)

46

34

44

32

42

30

40

PSNR(dB)

PSNR(dB)

38

28

36

26

34

24

WIRE

3D GS

JPEG

Balle18

32

SIREN

I-NGP

JPEG2000

COIN Ours

22

NeuRBF

Ours

Balle17

30

10 3 10 2 10 1 Decoding Time (s)

10 3 10 2 10 1 Decoding Time (s)

- Fig. 1: Image representation (left) and compression (right) results with different decoding time on the Kodak and DIV2K dataset, respectively. The radius of each point indicates the parameter size (left) or bits per pixel (right). Our method enjoys the fastest decoding speed regardless of parameter size or bpp.

transform [30], and discrete cosine transform [3], have been extensively applied across a broad spectrum of applications, from image compression to vision task analysis. However, these techniques encounter significant obstacles when processing large-scale datasets and striving for highly efficient storage solutions.

The advent of implicit neural representations (INRs) [54,56] marks a significant paradigm shift in image representation techniques. Typically, INRs employ a compact neural network to derive an implicit continuous mapping from input coordinates to the corresponding output values. This allows INRs to capture and retain image details with greater efficiency, which provides considerable benefits across various applications, including image compression [22,23,27,57], deblurring [50,65,67], and super-resolution [15,43,49]. However, most state-of-the-art INR methods [25,51,53,54,59] rely on a large high-dimensional multi-layer perceptron (MLP) network to accurately represent high-resolution images. This dependency leads to prolonged training times, increased GPU memory requirements, and slow decoding speed. While recent innovations [18, 44, 48, 58] have introduced multi-resolution feature grids coupled with a compact MLP to accelerate training and inference, they still require enough GPU memory to support their fast training and inference, which is difficult to meet when resources are limited. Consequently, these challenges substantially hinder the practical deployment of INRs in real-world scenarios.

In light of these challenges, our research aims to develop an advanced image representation technique that enables efficient training, friendly GPU memory usage, and fast decoding. To achieve this goal, we resort to Gaussian Splatting (GS) [35] that is recently developed for 3D scene reconstruction. By leveraging explicit 3D Gaussian representations and differentiable tile-based rasterization, 3D GS not only enjoys high visual quality with competitive training times, but also achieves real-time rendering capabilities.

Nevertheless, it is non-trivial to directly adapt 3D GS for efficient single image representation. Firstly, considering that existing 3D GS methods [12, 35]

depend on varying camera transformation matrices to render images from different perspectives, a straightforward adaptation for single image is fixing the camera transformation matrix to render an image from a single viewing angle. Unfortunately, each 3D Gaussian usually includes 59 learnable parameters [35] and thousands of 3D Gaussians are required for representing a single image. This naive approach substantially increases the storage and communication demands. As can be inferred from Table 1, the storage footprint for a single image with tens of kilobytes can escalate to dozens of megabytes, which makes rendering difficult on low-end devices with limited memory. Secondly, the rasterization algorithm [35] in 3D GS, designed for α-blending approximation, necessitates pre-sorted Gaussians based on depth information derived from camera parameters. This poses a challenge for single images because detailed camera parameters are often not known in natural individual image, while non-natural images, including screenshots and AI-generated content, are not captured by cameras. Without accurate depth information, the Gaussian sorting might be impaired, diminishing the final fitting performance. Moreover, the current rasterization process skips the remaining Gaussians once the accumulated opacity surpasses the given threshold, which results in underutilization of Gaussian data, thereby requiring more Gaussians for high-quality rendering.

To address these issues, we propose a new paradigm of image representation and compression, namely GaussianImage, using 2D Gaussian Splatting. Firstly, we adopt 2D Gaussians in lieu of 3D for a compact and expressive representation. Each 2D Gaussian is defined by 4 attributes (9 parameters in total): position, anisotropic covariance, color coefficients, and opacity. This modification results in a 6.5× compression over 3D Gaussians with equivalent Gaussian points, significantly mitigating storage demands of Gaussian representation. Subsequently, we advocate a unique rasterization algorithm that replaces depth-based Gaussian sorting and α-blending with a accumulated summation process. This novel approach directly computes each pixel’s color from the weighted sum of 2D Gaussians, which not only fully utilizes the information of all Gaussian points covering the current pixel to improve fitting performance, but also avoids the tedious calculation of accumulated transparency to accelerate training and inference speed. More important, this summation mechanism allows us to merge color coefficients and opacity into a singular set of weighted color coefficients, reducing parameter count to 8 and further improving the compression ratio to 7.375×. Finally, we transfer our 2D Gaussian representation into a practical image codec. Framing image compression as a Gaussian attribute compression task, we employ a two-step compression strategy: attribute quantization-aware fine-tuning and encoding. By applying 16-bit float quantization, 6-bit integer quantization [11], and residual vector quantization (RVQ) [73] to positions, covariance parameters, and weighted color coefficients, respectively, we successfully develop the first image codec based on 2D Gaussian Splatting. As a preliminary proof of concept, the partial bits-back coding [52,60] is optionally used to further improve the compression performance of our codec. Overall, our contributions are threefold:

- • We present a pioneering paradigm of image representation and compression by 2D Gaussian Splatting. With compact 2D Gaussian representation and a novel accumulated blending-based rasterization method, our approach achieves high representation performance with short training duration, minimal GPU memory overhead and remarkably, 2000 FPS rendering speed.
- • We develop a low-complexity neural image codec using vector quantization. Furthermore, a partial bits-back coding technique is optionally used to reduce the bitrate.
- • Experimental results show that when compared with existing INR methods, our approach achieves a remarkable training and inference acceleration with less GPU memory usage while maintaining similar visual quality. When used as an efficient image codec, our approach offers competitive compression performance comparable to COIN [23] and COIN++ [22]. Comprehensive ablations and analyses demonstrate the effectiveness of each proposed component.

### 2 Related Works

- 2.1 Implicit Neural Representation

Recently, implicit neural representation has gained increasing attention for its wide-ranging potential applications, such as 3D scene rendering [7, 8, 46, 66], image [18,48,53,54] and video [13,14,40,74] representations. We roughly classified existing image INRs into two categories: (i) MLP-based INRs [25,51,53,54,59] take position encoding of spatial coordinates as input of an MLP network to learn the RGB values of images, while they only rely on the neural network to encode all the image information, resulting in inefficient training and inference especially for high-resolution image.(ii) Feature grid-based INRs [18,44,48,58] adopt a large-scale multi-resolution grid, such as quadtree and hash table, to provide prior information for a compact MLP. This reduces the learning difficulty of MLP to a certain extent and accelerates the training process, making INRs more practical. Unfortunately, they still consume large GPU memory, which is difficult to accommodate on low-end devices. Instead of following existing INR methods, we aim to propose a brand-new image representation paradigm based on 2D Gaussian Splatting, which enables us to enjoy swifter training, faster rendering, and less GPU resource consumption.

- 2.2 Gaussian Splatting

Gaussian Splatting [35] has recently gained tremendous traction as a promising paradigm to 3D view synthesis. With explicit 3D Gaussian representations and differentiable tile-based rasterization, GS not only brings unprecedented control and editability but also facilitates high-quality and real-time rendering in

- 3D scene reconstruction. This versatility has opened up new avenues in various domains, including simultaneous localization and mapping (SLAM) [33,34,68],

[Figure 1]

[Figure 2]

[Figure 3]

Rasterization

2D Gaussian Formation

Acummulated Blending

- Fig. 2: Our proposed GaussianImage framework. 2D Gaussians are first formatted and then rasterized to generate the output image. The rasterizer uses our proposed accumulated blending for efficient 2D image representation.

dynamic scene modeling [42, 63, 70], AI-generated content [16, 19, 76], and autonomous driving [69,75]. Despite its great success in 3D scenarios, the application of GS to single image representation remains unexplored. Our work pioneers the adaptation of GS for 2D image representation, leveraging the strengths of GS in highly parallelized workflow and real-time rendering to outperform INR-based methods in terms of training efficiency and decoding speed.

- 2.3 Image Compression

Traditional image compression techniques, such as JPEG [61], JPEG2000 [55] and BPG [10], follow a transformation, quantization, and entropy coding procedure to achieve good compression efficiency with decent decompression speed. Recently, learning-based image compression methods based on variational autoencoder (VAE) have re-imagined this pipeline, integrating complex nonlinear transformations [4, 20, 28, 41] and advanced entropy models [5, 6, 36, 47]. Despite these methods surpassing traditional codecs in rate-distortion (RD) performance, their extremely high computational complexity and very slow decoding speed severely limit their practical deployment. To tackle the computational inefficiency of existing art, some works have explored INR-based compression methods [22, 23, 27, 38, 39, 57]. However, as image resolutions climb, their decoding speeds falter dramatically, challenging their real-world applicability. In this paper, our approach diverges from VAE and INR paradigms, utilizing 2D Gaussian Splatting to forge a neural image codec with unprecedented decoding efficiency. This marks an important milestone for neural image codecs.

- 3 Method

- Fig. 2 delineates the overall processing pipeline of our GaussianImage. Our approach begins by forming 2D Gaussians on an image plane, a process mainly calculating the 2D covariance matrix Σ. Afterwards, we employ an accumulated blending mechanism to compute the value for each pixel. In what follows, we begin with the formation of a 2D Gaussian in Section 3.1. Next, we describe how to adapt the rasterization process of 3D GS to align the unique characteristics of 2D image representation and upgrade 2D Gaussian with less parameters in Section 3.2. Then, we present a two-step compression pipeline to convert our GaussianImage into a neural image codec in Section 3.3. Finally, we state the training process on the image representation and compression tasks in Section 3.4.

#### 3.1 2D Gaussian Formation

In 3D Gaussian Splatting, each 3D Gaussian is initially mapped into a 2D plane through viewing and projection transformation. Then a differentiable rasterizer is used to render the current view image from these projected Gaussians. Since our application is no longer oriented to 3D scenes, but to 2D image representation, we discard many bloated operations and redundant parameters in 3D GS, such as project transformation, spherical harmonics, etc.

In our framework, the image representation unit is a 2D Gaussian. The basic 2D Gaussian is described by its position µ ∈ R2, 2D covariance matrix Σ ∈ R2×2, color coefficients c ∈ R3 and opacity o ∈ R. Note that covariance matrix Σ of a Gaussian distribution requires positive semi-definite. Typically, it is difficult to constrain the learnable parameters using gradient descent to generate such valid matrices. To avoid producing invalid matrix during training, we choose to optimize the factorized form of the covariance matrix. Here, we present two decomposition ways to cover all the information of the original covariance matrix. One intuitive decomposition is the Cholesky factorization [31], which breaks down Σ into the product of a lower triangular matrix L ∈ R2×2 and its conjugate transpose LT:

Σ = LLT. (1)

For the sake of writing, we use a Choleksy vector l = {l1,l2,l3} to represent the lower triangular elements in matrix L. When compared with 3D Gaussian having 59 learnable parameters, our 2D Gaussian only require 9 parameters, making it more lightweight and suitable for image representation.

Another decomposition follows 3D GS [35] to factorize the covariance matrix into a rotation matrix R ∈ R2×2 and scaling matrix S ∈ R2×2:

Σ = (RS)(RS)T, (2) where the rotation matrix R and the scaling matrix S are expressed as

R =

cos(θ) −sin(θ) sin(θ) cos(θ)

, S =

s1 0 0 s2

. (3)

Here, θ represents the rotation angle. s1 and s2 are scaling factors in different eigenvector directions. While the decomposition of the covariance matrix is not unique, they have equivalent capabilities to represent the image. However, the robustness to compression of different decomposition forms is inconsistent, which is explained in detail in the appendix. Therefore, we need to carefully choose the decomposition form of the covariance matrix when facing different image tasks.

#### 3.2 Accumulated Blending-based Rasterization

During the rasterization phase, 3D GS first forms a sorted list of Gaussians N based on the projected depth information. Then the α-blending is adopted to

render pixel i:

n−1

(1 − αm), (4)

cn · αn · Tn, Tn =

Ci =

m=1

n∈N

where Tn denotes the accumulated transparency. The αn is computed with projected 2D covariance Σ and opacity on:

αn = on · exp(−σn), σn =

- 1

- 2

dTnΣ−1dn, (5)

where d ∈ R2 is the displacement between the pixel center and the projected 2D Gaussian center.

Since the acquisition of depth information involves viewing transformation, it requires us to know the intrinsic and extrinsic parameters of the camera in advance. However, it is difficult for natural individual image to access the detailed camera parameters, while non-natural images, such as screenshots and AI-generated content, are not captured by the camera. In this case, retaining the α-blending of the 3D GS without depth cues would result in arbitrary blending sequences, compromising the rendering quality. Moreover, 3D GS only maintains Gaussians with a 99% confidence interval in order to solve the problem of numerical instability in computing the projected 2D covariance, but this makes only part of Gaussians covering pixel i contribute to the rendering of pixel i, leading to inferior fitting performance.

To overcome these limitations, we propose an accumulated summation mechanism to unleash the potential of our 2D Gaussian representation. Since there is no viewpoint influence when rendering an image, the rays we observe from each element are determined, and so as all the α values. Therefore, we merge the Tn part in Equation 4 into the on term, and simplify the computation consuming α-blending to a weighted sum:

cn · αn =

cn · on · exp(−σn). (6)

Ci =

n∈N

n∈N

This removes the necessity of Gaussian sequence order, so that we can remove the sorting from rasterization.

This novel rasterization algorithm brings multiple benefits. First, our accumulated blending process is insensitive to the order of Gaussian points. This property allows us to avoid the impact of the random order of Gaussian points on rendering, achieving robustness to any order of Gaussian points. Second, when compared with Equation 4, our rendering skips the tedious sequential calculation of accumulated transparency Tn, improving our training efficiency and rendering speed. Third, since the color coefficients cn and the opacity on are learnable parameters, they can be merged to further simplify Equation 6:

Ci =

c′n · exp(−σn), (7)

n∈N

Ultra-fast Image Codec

Best Image Codec

Attribute Quantizationaware Fine-tuning

Image Overfitting

Partial Bits-Back Coding

Covariance: b-bit Interger Quantization

Color: Residual Vector Quantization

Position: FP16

- Fig. 3: Compression pipeline of our proposed GaussianImage. After overfitting image, we apply attribute quantization-aware fine-tuning to build an ultra-fast image codec. Partial bits-back coding is used to achieve the best compression performance.

where the weighted color coefficients c′n ∈ R3 is no longer limited in the range of [0,1]. In this way, instead of the basic 2D Gaussian that requires 4 attributes in Section 3.1, our upgraded 2D Gaussian is described by only 3 attributes (i.e., position, covariance, and weighted color coefficients) with a total of 8 parameters. This further improves the compression ratio to 7.375× when compared with 3D Gaussian under equivalent Gaussian points.

#### 3.3 Compression Pipeline

After overfitting the image, we propose a compression pipeline for image compression with GaussianImage. As shown in Fig. 3, our standard compression pipeline is composed of two steps: image overfitting and attribute quantizationaware fine-tuning. To achieve the best compression performance, partial bitsback coding [52,60] is an optional strategy. Herein, we elucidate the compression process using our GaussianImage based on Cholesky factorization as an example. Attribute Quantization-aware Fine-tuning. Given a set of 2D Gaussian points fit on an image, we apply distinct quantization strategies to various attributes. Since the Gaussian location is sensitive to quantization, we adopt 16bit float precision for position parameters to preserve reconstruction fidelity. For Choleksy vector ln in the n-th Gaussian, we incorporate a b-bit asymmetric quantization technique [11], where both the scaling factor γi and the offset factor βi are learned during fine-tuning:

ˆlin = clamp

lin − βi γi

,0,2b − 1 , ¯lin = ˆlin × γi + βi, (8)

where i ∈ {0,1,2}. Note that we share the same scaling and offset factors at all Gaussians in order to reduce metadata overhead. After fine-tuning, the covariance parameters are encoded with b-bit precision, while the scaling and offset values required for re-scaling are stored in 32-bit float precision.

As for weighted color coefficients, a codebook enables representative color attribute encoding via vector quantization (VQ) [26]. While naively applying vector quantization leads to inferior rendering quality, we employ residual vector

quantization (RVQ) [73] that cascades M stages of VQ with codebook size B to mitigate performance degradation:

m

cˆ′nm =

Ck[ik], m ∈ {1,··· ,M},

(9)

k=1

Cm[k] − (c′n − cˆ′nm−1) 22 , cˆ′n0 = 0,

imn = arg min

m

where cˆ′nm denotes the output color vector after m quantization stages, Cm ∈ RB×3 represents the codebook at the stage m, im ∈ {0,··· ,B − 1}N is the codebook indices at the stage m, and C[i] ∈ R3 is the vector at index i of the codebook C. To train the codebooks, we apply the commitment loss Lc as follows:

M

N

1 N × B

sg[c′n − cˆ′nk−1] − Ck[ikn] 22 , (10) where N is the number of Gaussians and sg[·] is the stop-gradient operation.

Lc =

n=1

k=1

Partial Bits-Back Coding. As we have not adopted any auto-regressive context [47] to encode 2D Gaussian parameters, any permutation of 2D Gaussian points can be seen as an equivariant graph without edge. Therefore, we can adopt bits-back coding [60] for equivariant graph described by [37] to save bitrate. More specifically, [37] show that an unordered set with N elements has N! equivariant, and bits-back coding can save a bitrate of

log N! − log N, (11) compared with directly store those unordered elements.

However, the vanilla bits-back coding requires initial bits [60] of log N!, which means that it can only work on a dataset, not on a single image. To tackle this challenge, [52] introduces a partial bits-back coding strategy that segments the image data, applying vanilla entropy coding to a fraction of the image as the initial bit allocation, with the remainder encoded via bits-back coding.

In our case, we reuse the idea of [52]. Specifically, we encode the initial K Gaussians by vanilla entropy coding, and the subsequent N − K Gaussians by bits-back coding. This segmented approach is applicable to single image compression, contingent upon the bitrate of the initial K Gaussian exceeding the initial bits log(N − K)!. Let Rk denotes the bitrate of k-th Gaussian, the final bitrate saving can be formalized as:

log(N − K∗)! − log(N − K∗), (12)

K

where K∗ = inf K,s.t.

Rk − log(N − K∗)! ≥ 0. (13)

k=1

Despite its theoretical efficacy, bits-back coding may not align with the objective of developing an ultra-fast codec due to its slow processing latency [37]. Consequently, we leave this part as a preliminary proof of concept on the best rate-distortion performance our codec can achieve, instead of a final result of our codec can achieve with 2000 FPS.

- Table 1: Quantitative comparison with various baselines in PSNR, MS-SSIM, training time, rendering speed, GPU memory usage and parameter size.

- (a) Kodak dataset

Methods PSNR↑ MS-SSIM↑ Training Time(s)↓ FPS↑ GPU Mem(MiB)↓ Params(K)↓

WIRE [53] 41.47 0.9939 14338.78 11.14 2619 136.74 SIREN [54] 40.83 0.9960 6582.36 29.15 1809 272.70 I-NGP [48] 43.88 0.9976 490.61 1296.82 1525 300.09 NeuRBF [18] 43.78 0.9964 991.83 663.01 2091 337.29 3D GS [35] 43.69 0.9991 339.78 859.44 557 3540.00 Ours 44.08 0.9985 106.59 2092.17 419 560.00

- (b) DIV2K dataset

Methods PSNR↑ MS-SSIM↑ Training Time(s)↓ FPS↑ GPU Mem(MiB)↓ Params(K)↓

WIRE [53] 35.64 0.9511 25684.23 14.25 2619 136.74 SIREN [54] 39.08 0.9958 15125.11 11.07 2053 483.60 I-NGP [48] 37.06 0.9950 676.29 1331.54 1906 525.40 NeuRBF [18] 38.60 0.9913 1715.44 706.40 2893 383.65

- 3D GS [35] 39.36 0.9979 481.27 640.33 709 4130.00 Ours 39.53 0.9975 120.76 1737.60 439 560.00

3.4 Training

For image representation, our objective is to minimize the distortion between the original image x and reconstructed image xˆ. To this end, we employ the L2 loss function to optimize the Gaussian parameters. It is worth noting that previous GS method [35] introduces adaptive density control to split and clone Gaussians when optimizing 3D scenes. Since there exists many empty areas in the 3D space, they need to consider avoiding populating these areas. By contrast, there is no so-called empty area in the 2D image space. Therefore, we discard adaptive density control, which greatly simplifies the optimization process of 2D image representation.

As for image compression task, the overall loss L consists of the reconstruction loss Lrec and the commitment loss Lc:

L = Lrec + λLc, (14)

where λ serves as a hyper-parameter, balancing the weight of each loss component. The color codebooks are initialized using the K-means algorithm, providing a robust starting point for subsequent optimization. During fine-tuning, we adopt the exponential moving average mode to update the codebook.

- 4 Experiments

#### 4.1 Experimental Setup

Dataset. Our evaluation in image representation and compression is conducted on two popular datasets. We use the Kodak dataset [1], which consists of 24 images with a resolution of 768×512, and the DIV2K validation set [2] with 2× bicubic downscaling, featuring 100 images with dimensions varying from 408×1020 to 1020×1020.

Kodak Dataset

Kodak Dataset

1.00

38

36

0.95

34

0.90

PSNR(dB)

MS-SSIM

32

30

0.85

28

JPEG

COIN Ours Ours+BB

0.80

JPEG2000

JPEG

COIN Ours Ours+BB

26

- Balle17

- Balle18

JPEG2000

Ours-Bound

- Balle17

- Balle18

24

0.75

COIN++

Ours-Bound

0.2 0.4 0.6 0.8 1.0 1.2 1.4 Bpp

0.2 0.4 0.6 0.8 1.0 1.2 1.4 Bpp

DIV2K Dataset

DIV2K Dataset

1.00

38

36

0.95

34

32

PSNR(dB)

MS-SSIM

0.90

30

28

0.85

26

JPEG

COIN Ours Ours+BB

JPEG

COIN Ours Ours+BB

24

JPEG2000

JPEG2000

- Balle17

- Balle18

- Balle17

- Balle18

0.80

22

Ours-Bound

Ours-Bound

0.2 0.4 0.6 0.8 1.0 1.2 1.4 Bpp

0.2 0.4 0.6 0.8 1.0 1.2 1.4 Bpp

- Fig. 4: Rate-distortion curves of our approach and different baselines on Kodak and DIV2K datasets in PSNR and MS-SSIM. BB denotes partial bits-back coding. Bound denotes the theoretical rate of our codec.

Evaluation Metrics. To assess image quality, we employ two esteemed metrics: PSNR and MS-SSIM [62], which measure the distortion between reconstructed images and their originals. The bitrate for image compression is quantified in bits per pixel (bpp).

Implementation Details. Our GaussianImage, developed on top of gsplat [72], incorporates custom CUDA kernels for rasterization based on accumulated blending. We represent the covariance of 2D Gaussians using Cholesky factorization unless otherwise stated. The Gaussian parameters are optimized over 50000 steps using the Adan optimizer [64], starting with an initial learning rate of 1e−3, halved every 20000 steps. During attribute quantization-aware fine-tuning, the quantization precision b of covariance parameters is set to 6 bits, with the RVQ color vectors’ codebook size B and the number of quantization stages M fixed at 8 and 2, respectively. The iterations of K-means algorithm are set to 5. Experiments are performed using NVIDIA V100 GPUs and PyTorch, with further details available in the supplementary material.

Benchmarks. For image representation comparisons, GaussianImage is benchmarked against competitive INR methods like SIREN [54], WIRE [53], I-NGP [48], and NeuRBF [18]. As for image compression, baselines span traditional codecs (JPEG [61], JPEG2000 [55]), VAE-based codecs (Ballé17 [5], Ballé18 [6]),

bpp=0.244, PSNR=22.58, MS-SSIM=0.8256 bpp=0.226, PSNR=22.38, MS-SSIM=0.8094 bpp=0.218, PSNR=23.22, MS-SSIM=0.8725

bpp=0.217, PSNR=24.88, MS-SSIM=0.8857

bpp=0.217, PSNR=25.02, MS-SSIM=0.9332 bpp=0.165, PSNR=24.98, MS-SSIM=0.9120

[Figure 4]

[Figure 5]

[Figure 6]

[Figure 7]

[Figure 8]

[Figure 9]

(b)	JPEG2000

(c)	Balle17́ (d)	Balle18́

(a) JPEG (e) COIN (f) Proposed

Fig. 5: Subjective comparison of various codecs on Kodak at low Bpp.

- Table 2: Computational complexity of traditional and learning-based image codecs on DIV2K Dataset at low and high Bpp.

Methods Bpp↓ PSNR↑ MS-SSIM↑ Encoding FPS↑ Decoding FPS↑ JPEG [61] 0.3197/0.5638 25.2920/28.4299 0.9020/0.9559 608.61/557.35 614.68/545.59 JPEG2000 [55] 0.2394/0.5993 27.2792/30.9294 0.9305/0.9663 3.46/3.40 4.32/3.93

- Ballé17 [5] 0.2271/0.4987 27.7168/30.7759 0.9508/0.9775 21.23/16.53 18.83/17.87

- Ballé18 [6] 0.2533/0.5415 28.7548/32.2351 0.9584/0.9816 16.53/13.56 15.87/15.20 COIN [23] 0.3419/0.6780 25.8012/27.6126 0.8905/0.9306 5.30e−4/3.51e−4 166.31/93.74 Ours 0.3221/0.6417 25.6631/27.5656 0.9154/0.9483 4.11e−3/4.73e−3 1970.76/1980.54

INR-based codecs (COIN [23], COIN++ [22]). We utilize the open-source PyTorch implementation [17] of NeuRBF for I-NGP. These INR methods maintain consistent training steps with GaussianImage. Detailed implementation notes for baselines are found in the appendix.

#### 4.2 Image Representation

Fig. 1 (left) and Table 1 show the representation performance of various methods on the Kodak and DIV2K datasets under the same training steps. Although MLP-based INR methods (SIREN [54], WIRE [53]) utilize fewer parameters to fit an image, they suffer from enormous training time and hyperslow rendering speed. Recent feature grid-based INR methods (I-NGP [48], NeuRBF [18]) accelerate training and inference, but they demand substantially more GPU memory compared to GS-based methods. Since the original 3D GS uses 3D Gaussian as the representation unit, it face the challenge of giant parameter count, which decelerates training and restricts inference speed. By choosing 2D Gaussian as the representation unit, our method secures pronounced advantages in training duration, rendering velocity, and GPU memory usage, while substantially reducing the number of stored parameters yet preserving comparable fitting quality.

#### 4.3 Image Compression

Coding performance. Fig. 4 presents the RD curves of various codecs on the Kodak and DIV2K datasets. Notably, our method achieves comparable compression performance with COIN [23] and COIN++ [22] in PSNR. With the help of the partial bits-back coding, our codec can outperform COIN and COIN++. Furthermore, when measured by MS-SSIM, our method surpasses COIN by a large margin. Fig. 5 provides a qualitative comparison between our method, JPEG [61], and COIN, revealing that our method restores image details more effectively and delivers superior reconstruction quality by consuming lower bits.

- Table 3: Ablation study of image representation on Kodak dataset with 30000 Gaussian points over 50000 training steps. AR means accumulated blending-based rasterization, M indicates merging color coefficients c and opacity o. RS denotes decomposing the covariance matrix into rotation and scaling matrices. The final row in each subclass represents our default solution.

Methods PSNR↑ MS-SSIM↑ Training Time(s)↓ FPS↑ Params(K)↓

3D GS (w/ L1+SSIM) 37.75 0.9961 285.26 1067 1770 3D GS (w/ L2) 37.41 0.9947 197.90 1190 1770 Ours (w/ L2+w/o AR+w/o M) 37.89 0.9961 104.76 2340 270 Ours (w/ L2+w/ AR+w/o M) 38.69 0.9963 98.54 2555 270 Ours(w/ L2+w/ AR+w/ M) 38.57 0.9961 91.06 2565 240

Ours (w/ L1) 36.46 0.9937 92.68 2438 240 Ours (w/ SSIM) 35.65 0.9952 183.20 2515 240 Ours (w/ L1+SSIM) 36.57 0.9945 188.22 2576 240 Ours (w/ L2+SSIM) 34.73 0.9932 189.17 2481 240 Ours (w/ L2) 38.57 0.9961 91.06 2565 240

Ours-RS 38.83 0.9964 98.55 2321 240 Ours-Cholesky 38.57 0.9961 91.06 2565 240

Computational complexity. Table 2 reports the computational complexity of several image codecs on the DIV2K dataset, with learning-based codecs operating on an NVIDIA V100 GPU and traditional codecs running on an Intel Core(TM) i9-10920X processor at a base frequency of 3.50GHz in single-thread mode. Impressively, the decoding speed of our codec reaches around 2000 FPS, outpacing traditional codecs like JPEG, while also providing enhanced compression performance at lower bitrates. This establishes a significant advancement in the field of neural image codecs.

#### 4.4 Ablation Study

Effect of different components. To highlight the contributions of the key components in GaussianImage, we conduct a comprehensive set of ablation studies, as detailed in Table 3. Initially, the original 3D GS [35] method, which employs a combination of L1 and SSIM loss, is adapted to use L2 loss. This modification halves the training time at a minor cost to performance. Then, we replace the 3D Gaussian with the basic 2D Gaussian in Section 3.1, which not only improves the fitting performance and decreases training time by 13, but also doubles the inference speed and reduces parameter count by 6.5×. By simplifying alpha blending to accumulated blending, we eliminate the effects of random 2D Gaussian ordering and bypasses the complex calculations for the accumulated transparency T, resulting in a significant 0.8dB improvement in PSNR alongside notable training and inference speed gains. This underscores the efficiency of our proposed accumulated blending approach. Furthermore, by merging the color vector c and opacity o to form our upgraded 2D Gaussian, we observe a 10% reduction in parameter count with a negligible 0.1dB decrease in PSNR.

Loss function. We evaluate various combinations of L2, L1, and SSIM losses, with findings presented in Table 3. These results confirm that L2 loss is optimally

- Table 4: Ablation study of quantization schemes on Kodak dataset. The first row denotes our final solution and is set as the anchor.

Variants BD-PSNR (dB) ↑ BD-rate (%) ↓ BD-MS-SSIM ↑ BD-rate (%) ↓ Ours 0 0 0 0 (V1) w/o Lc+w/ RVQ + 6bit -3.145 333.16 -0.0824 337.84 (V2) w/o Lc+w/o RVQ + 6bit -0.159 7.02 -0.0030 6.14 (V3) w/o Lc+w/o RVQ + 8bit -0.195 11.69 -0.0127 62.77

suited for our approach, significantly improving image reconstruction quality while facilitating rapid training.

Factorized form of covariance matrix. As outlined in Section 3.1, we optimize the factorized form of the covariance matrix through decomposition. The findings detailed in Table 3 demonstrate that various factorized forms possess similar capabilities in representing images, despite the decomposition’s inherent non-uniqueness. The appendix provides additional analysis on the compression robustness of different factorized forms.

Quantization strategies. Table 4 investigates the effect of different quantization schemes on image compression. Without the commitment loss Lc (V1), the absence of supervision for the RVQ codebook leads to significant deviations of the codebook vector from the original vector, adversely affecting reconstruction quality. Moreover, eliminating RVQ in favor of 6-bit integer quantization for color parameters (V2) resulted in a 7.02% increase in bitrate consumption when compared with our default solution. This outcome suggests that the color vectors across different Gaussians share similarities, making them more suitable for RVQ. Further exploration into the use of higher bit quantization (V3) reveals a deterioration in compression efficiency.

- 5 Conclusion

In this work, we introduce GaussianImage, an innovative paradigm for image representation that leverages 2D Gaussian Splatting. This approach diverges significantly from the commonly utilized implicit neural networks, offering a discrete and explicit representation of images. When compared to 3D Gaussian Splatting, employing 2D Gaussian kernels brings forth two notable benefits for image representation. Firstly, the computationally intensive alpha blending is simplified to an efficient and permutation-invariant accumulated summation blending. Secondly, the quantity of parameters required for each Gaussian diminishes drastically from 59 to just 8, marking a substantial reduction in complexity. Consequently, GaussianImage emerges as a highly efficient and compact technique for image coding. Experimental results confirm that this explicit representation strategy enhances training and inference efficiency substantially. Moreover, it delivers a competitive rate-distortion performance after adopting vector quantization on parameters, compared to methods adopting implicit neural representation. These findings suggest promising avenues for further exploration in non-end-to-end image compression and representation strategies.

Acknowledgments. This work was supported by the National Natural Science Fund of China (Project No. 42201461, 62102024, 62331014) and the General Research Fund (Project No. 16209622) from the Hong Kong Research Grants Council.

### References

- 1. Kodak lossless true color image suite. https://r0k.us/graphics/kodak/ (1999) 10
- 2. Agustsson, E., Timofte, R.: Ntire 2017 challenge on single image super-resolution: Dataset and study. In: The IEEE Conference on Computer Vision and Pattern Recognition (CVPR) Workshops (July 2017) 10
- 3. Ahmed, N., Natarajan, T., Rao, K.R.: Discrete cosine transform. IEEE transactions on Computers 100(1), 90–93 (1974) 2
- 4. Ballé, J., Laparra, V., Simoncelli, E.P.: Density modeling of images using a generalized normalization transformation. arXiv preprint arXiv:1511.06281 (2015) 5
- 5. Ballé, J., Laparra, V., Simoncelli, E.P.: End-to-end optimized image compression. In: International Conference on Learning Representations (2017) 5, 11, 12, 23, 25
- 6. Ballé, J., Minnen, D., Singh, S., Hwang, S.J., Johnston, N.: Variational image compression with a scale hyperprior. In: International Conference on Learning Representations (2018) 5, 11, 12, 23, 25
- 7. Barron, J.T., Mildenhall, B., Tancik, M., Hedman, P., Martin-Brualla, R., Srinivasan, P.P.: Mip-nerf: A multiscale representation for anti-aliasing neural radiance fields. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 5855–5864 (2021) 4
- 8. Barron, J.T., Mildenhall, B., Verbin, D., Srinivasan, P.P., Hedman, P.: Mipnerf 360: Unbounded anti-aliased neural radiance fields. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 5470– 5479 (2022) 4
- 9. Bégaint, J., Racapé, F., Feltman, S., Pushparaja, A.: Compressai: a pytorch library and evaluation platform for end-to-end compression research. arXiv preprint arXiv:2011.03029 (2020) 23
- 10. Bellard, F.: Bpg image format. https://bellard.org/bpg/ (2014) 5
- 11. Bhalgat, Y., Lee, J., Nagel, M., Blankevoort, T., Kwak, N.: Lsq+: Improving lowbit quantization through learnable offsets and better initialization. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition Workshops. pp. 696–697 (2020) 3, 8
- 12. Chen, G., Wang, W.: A survey on 3d gaussian splatting. arXiv preprint arXiv:2401.03890 (2024) 2
- 13. Chen, H., Gwilliam, M., Lim, S.N., Shrivastava, A.: Hnerv: A hybrid neural representation for videos. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 10270–10279 (2023) 4
- 14. Chen, H., He, B., Wang, H., Ren, Y., Lim, S.N., Shrivastava, A.: Nerv: Neural representations for videos. Advances in Neural Information Processing Systems 34, 21557–21568 (2021) 4
- 15. Chen, Y., Liu, S., Wang, X.: Learning continuous image representation with local implicit image function. In: Proceedings of the IEEE/CVF conference on computer vision and pattern recognition. pp. 8628–8638 (2021) 2

- 16. Chen, Y., Chen, Z., Zhang, C., Wang, F., Yang, X., Wang, Y., Cai, Z., Yang, L., Liu, H., Lin, G.: Gaussianeditor: Swift and controllable 3d editing with gaussian splatting. In: IEEE Conference on Computer Vision and Pattern Recognition (CVPR) (2024) 5, 25
- 17. Chen, Z., Li, Z., Song, L., Chen, L., Yu, J., Yuan, J., Xu, Y.: https://github. com/oppo-us-research/NeuRBF 12
- 18. Chen, Z., Li, Z., Song, L., Chen, L., Yu, J., Yuan, J., Xu, Y.: Neurbf: A neural fields representation with adaptive radial basis functions. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 4182–4194 (2023) 2, 4, 10, 11, 12, 23
- 19. Chen, Z., Wang, F., Liu, H.: Text-to-3d using gaussian splatting. In: IEEE Conference on Computer Vision and Pattern Recognition (CVPR) (2024) 5
- 20. Cheng, Z., Sun, H., Takeuchi, M., Katto, J.: Learned image compression with discretized gaussian mixture likelihoods and attention modules. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 7939–7948 (2020) 5
- 21. Duda, J.: Asymmetric numeral systems: entropy coding combining speed of huffman coding with compression rate of arithmetic coding. arXiv: Information Theory

(2013), https://api.semanticscholar.org/CorpusID:13409455 22

- 22. Dupont, E., Loya, H., Alizadeh, M., Golinski, A., Teh, Y., Doucet, A.: Coin++: neural compression across modalities. Transactions on Machine Learning Research 2022(11) (2022) 2, 4, 5, 12
- 23. Dupont, E., Golinski, A., Alizadeh, M., Teh, Y.W., Doucet, A.: Coin: Compression with implicit neural representations. In: Neural Compression: From Information Theory to Applications–Workshop@ ICLR 2021 (2021) 2, 4, 5, 12, 23, 25
- 24. Fang, J., Wang, J., Zhang, X., Xie, L., Tian, Q.: Gaussianeditor: Editing 3d gaussians delicately with text instructions. arXiv preprint arXiv:2311.16037 (2023) 25
- 25. Fathony, R., Sahu, A.K., Willmott, D., Kolter, J.Z.: Multiplicative filter networks. In: International Conference on Learning Representations (2020) 2, 4
- 26. Gray, R.: Vector quantization. IEEE Assp Magazine 1(2), 4–29 (1984) 8
- 27. Guo, Z., Flamich, G., He, J., Chen, Z., Hernández-Lobato, J.M.: Compression with bayesian implicit neural representations. Advances in Neural Information Processing Systems 36 (2024) 2, 5
- 28. He, D., Yang, Z., Peng, W., Ma, R., Qin, H., Wang, Y.: Elic: Efficient learned image compression with unevenly grouped space-channel contextual adaptive coding. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 5718–5727 (2022) 5
- 29. He, D., Yang, Z., Yu, H., Xu, T., Luo, J., Chen, Y., Gao, C., Shi, X., Qin, H., Wang, Y.: Po-elic: Perception-oriented efficient learned image coding. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 1764–1769 (2022) 25
- 30. Heil, C.E., Walnut, D.F.: Continuous and discrete wavelet transforms. SIAM review 31(4), 628–666 (1989) 2
- 31. Higham, N.J.: Cholesky factorization. Wiley interdisciplinary reviews: computational statistics 1(2), 251–254 (2009) 6
- 32. Hu, Y., Yang, S., Yang, W., Duan, L.Y., Liu, J.: Towards coding for human and machine vision: A scalable image coding approach. In: 2020 IEEE International Conference on Multimedia and Expo (ICME). pp. 1–6. IEEE (2020) 25
- 33. Huang, H., Li, L., Cheng, H., Yeung, S.K.: Photo-slam: Real-time simultaneous localization and photorealistic mapping for monocular, stereo, and rgb-d cameras.

- arXiv preprint arXiv:2311.16728 (2023) 4

- 34. Keetha, N., Karhade, J., Jatavallabhula, K.M., Yang, G., Scherer, S., Ramanan, D., Luiten, J.: Splatam: Splat, track & map 3d gaussians for dense rgb-d slam.

- arXiv preprint arXiv:2312.02126 (2023) 4

- 35. Kerbl, B., Kopanas, G., Leimkühler, T., Drettakis, G.: 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics 42(4) (2023) 2, 3, 4, 6, 10, 13
- 36. Koyuncu, A.B., Gao, H., Boev, A., Gaikov, G., Alshina, E., Steinbach, E.: Contextformer: A transformer with spatio-channel attention for context modeling in learned image compression. In: European Conference on Computer Vision. pp. 447–463. Springer (2022) 5
- 37. Kunze, J., Severo, D., Zani, G., van de Meent, J.W., Townsend, J.: Entropy coding of unordered data structures. In: The Twelfth International Conference on Learning Representations (2024), https://openreview.net/forum?id=afQuNt3Ruh 9, 22
- 38. Ladune, T., Philippe, P., Henry, F., Clare, G., Leguay, T.: Cool-chic: Coordinatebased low complexity hierarchical image codec. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 13515–13522 (2023) 5
- 39. Leguay, T., Ladune, T., Philippe, P., Clare, G., Henry, F., Déforges, O.: Lowcomplexity overfitted neural image codec. In: 2023 IEEE 25th International Workshop on Multimedia Signal Processing (MMSP). pp. 1–6. IEEE (2023) 5
- 40. Li, Z., Wang, M., Pi, H., Xu, K., Mei, J., Liu, Y.: E-nerv: Expedite neural video representation with disentangled spatial-temporal context. In: European Conference on Computer Vision. pp. 267–284. Springer (2022) 4
- 41. Liu, J., Sun, H., Katto, J.: Learned image compression with mixed transformer-cnn architectures. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 14388–14397 (2023) 5
- 42. Luiten, J., Kopanas, G., Leibe, B., Ramanan, D.: Dynamic 3d gaussians: Tracking by persistent dynamic view synthesis. arXiv preprint arXiv:2308.09713 (2023) 5
- 43. Ma, C., Yu, P., Lu, J., Zhou, J.: Recovering realistic details for magnificationarbitrary image super-resolution. IEEE Transactions on Image Processing 31, 3669–3683 (2022) 2
- 44. Martel, J.N., Lindell, D.B., Lin, C.Z., Chan, E.R., Monteiro, M., Wetzstein, G.: Acorn: adaptive coordinate networks for neural scene representation. ACM Transactions on Graphics (TOG) 40(4), 1–13 (2021) 2, 4
- 45. Mentzer, F., Toderici, G.D., Tschannen, M., Agustsson, E.: High-fidelity generative image compression. Advances in Neural Information Processing Systems 33, 11913– 11924 (2020) 25
- 46. Mildenhall, B., Srinivasan, P.P., Tancik, M., Barron, J.T., Ramamoorthi, R., Ng, R.: Nerf: Representing scenes as neural radiance fields for view synthesis. In: European Conference on Computer Vision. pp. 405–421. Springer (2020) 4
- 47. Minnen, D., Ballé, J., Toderici, G.D.: Joint autoregressive and hierarchical priors for learned image compression. In: Advances in neural information processing systems (2018) 5, 9
- 48. Müller, T., Evans, A., Schied, C., Keller, A.: Instant neural graphics primitives with a multiresolution hash encoding. ACM Transactions on Graphics (ToG) 41(4), 1– 15 (2022) 2, 4, 10, 11, 12, 23
- 49. Nguyen, Q.H., Beksi, W.J.: Single image super-resolution via a dual interactive implicit neural network. In: Proceedings of the IEEE/CVF Winter Conference on Applications of Computer Vision. pp. 4936–4945 (2023) 2
- 50. Quan, Y., Yao, X., Ji, H.: Single image defocus deblurring via implicit neural inverse kernels. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 12600–12610 (2023) 2

- 51. Ramasinghe, S., Lucey, S.: Beyond periodicity: Towards a unifying framework for activations in coordinate-mlps. In: European Conference on Computer Vision. pp. 142–158. Springer (2022) 2, 4
- 52. Ryder, T., Zhang, C., Kang, N., Zhang, S.: Split hierarchical variational compression. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 386–395 (2022) 3, 8, 9
- 53. Saragadam, V., LeJeune, D., Tan, J., Balakrishnan, G., Veeraraghavan, A., Baraniuk, R.G.: Wire: Wavelet implicit neural representations. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 18507– 18516 (2023) 2, 4, 10, 11, 12, 23
- 54. Sitzmann, V., Martel, J., Bergman, A., Lindell, D., Wetzstein, G.: Implicit neural representations with periodic activation functions. Advances in neural information processing systems 33, 7462–7473 (2020) 2, 4, 10, 11, 12, 23
- 55. Skodras, A., Christopoulos, C., Ebrahimi, T.: The jpeg 2000 still image compression standard. IEEE Signal processing magazine 18(5), 36–58 (2001) 5, 11, 12
- 56. Stanley, K.O.: Compositional pattern producing networks: A novel abstraction of development. Genetic programming and evolvable machines 8, 131–162 (2007) 2
- 57. Strümpler, Y., Postels, J., Yang, R., Gool, L.V., Tombari, F.: Implicit neural representations for image compression. In: European Conference on Computer Vision. pp. 74–91. Springer (2022) 2, 5
- 58. Takikawa, T., Litalien, J., Yin, K., Kreis, K., Loop, C., Nowrouzezahrai, D., Jacobson, A., McGuire, M., Fidler, S.: Neural geometric level of detail: Real-time rendering with implicit 3d shapes. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 11358–11367 (2021) 2, 4
- 59. Tancik, M., Srinivasan, P., Mildenhall, B., Fridovich-Keil, S., Raghavan, N., Singhal, U., Ramamoorthi, R., Barron, J., Ng, R.: Fourier features let networks learn high frequency functions in low dimensional domains. Advances in Neural Information Processing Systems 33, 7537–7547 (2020) 2, 4
- 60. Townsend, J., Bird, T., Barber, D.: Practical lossless compression with latent variables using bits back coding. arXiv preprint arXiv:1901.04866 (2019) 3, 8, 9, 22
- 61. Wallace, G.K.: The jpeg still picture compression standard. Communications of the ACM 34(4), 30–44 (1991) 5, 11, 12
- 62. Wang, Z., Simoncelli, E.P., Bovik, A.C.: Multiscale structural similarity for image quality assessment. In: The Thrity-Seventh Asilomar Conference on Signals, Systems & Computers, 2003. vol. 2, pp. 1398–1402. Ieee (2003) 11
- 63. Wu, G., Yi, T., Fang, J., Xie, L., Zhang, X., Wei, W., Liu, W., Tian, Q., Wang, X.: 4d gaussian splatting for real-time dynamic scene rendering. arXiv preprint arXiv:2310.08528 (2023) 5
- 64. Xie, X., Zhou, P., Li, H., Lin, Z., Shuicheng, Y.: Adan: Adaptive nesterov momentum algorithm for faster optimizing deep models. In: Has it Trained Yet? NeurIPS 2022 Workshop (2022) 11
- 65. Xu, D., Wang, P., Jiang, Y., Fan, Z., Wang, Z.: Signal processing for implicit neural representations. Advances in Neural Information Processing Systems 35, 13404–13418 (2022) 2
- 66. Xu, Q., Xu, Z., Philip, J., Bi, S., Shu, Z., Sunkavalli, K., Neumann, U.: Point-nerf: Point-based neural radiance fields. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 5438–5448 (2022) 4
- 67. Xu, W., Jiao, J.: Revisiting implicit neural representations in low-level vision. In: International Conference on Learning Representations Workshop (2023) 2
- 68. Yan, C., Qu, D., Wang, D., Xu, D., Wang, Z., Zhao, B., Li, X.: Gs-slam: Dense visual slam with 3d gaussian splatting. arXiv preprint arXiv:2311.11700 (2023) 4

- 69. Yan, Y., Lin, H., Zhou, C., Wang, W., Sun, H., Zhan, K., Lang, X., Zhou, X., Peng, S.: Street gaussians for modeling dynamic urban scenes. arXiv preprint arXiv:2401.01339 (2024) 5
- 70. Yang, Z., Yang, H., Pan, Z., Zhu, X., Zhang, L.: Real-time photorealistic dynamic scene representation and rendering with 4d gaussian splatting. arXiv preprint arXiv:2310.10642 (2023) 5
- 71. Ye, V., Kanazawa, A.: Mathematical supplement for the gsplat library. arXiv preprint arXiv:2312.02121 (2023) 20
- 72. Ye, V., Turkulainen, M., the Nerfstudio team: gsplat, https://github.com/ nerfstudio-project/gsplat 11
- 73. Zeghidour, N., Luebs, A., Omran, A., Skoglund, J., Tagliasacchi, M.: Soundstream: An end-to-end neural audio codec. IEEE/ACM Transactions on Audio, Speech, and Language Processing 30, 495–507 (2021) 3, 9
- 74. Zhang, X., Yang, R., He, D., Ge, X., Xu, T., Wang, Y., Qin, H., Zhang, J.: Boosting neural representations for videos with a conditional decoder. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (2024) 4
- 75. Zhou, X., Lin, Z., Shan, X., Wang, Y., Sun, D., Yang, M.H.: Drivinggaussian: Composite gaussian splatting for surrounding dynamic autonomous driving scenes. arXiv preprint arXiv:2312.07920 (2023) 5
- 76. Zielonka, W., Bagautdinov, T., Saito, S., Zollhöfer, M., Thies, J., Romero, J.: Drivable 3d gaussian avatars. arXiv preprint arXiv:2311.08581 (2023) 5

### A Details of Gradient Computation

In this section, we delineate the process of computing the gradients of a scalar loss function with respect to the input Gaussian parameters. Beginning with the gradient of the scalar loss L with respect to each pixel of the output image, we employ the standard chain rule to propagate the gradients backward toward the original input parameters.

- A.1 Gradients of Accumulated Rasterization

The initial step involves back-propagating the loss gradients from a given pixel i to the Gaussian that contributed to the pixel. For a Gaussian n impacting pixel i, we aim to calculate the gradients with respect to its color c′ ∈ R3, the 2D means µ ∈ R2 and 2D covariance Σ ∈ R2×2.

For the color, we have

∂Cik ∂c′k

n

= exp(−σn). (15)

where k indicates the color channel. For the σn, we have

∂Cik ∂σn

= −exp(−σn). (16) For the 2D mean, we have

∂σn ∂µn

=

∂σn ∂dn

= Σ−n1dn ∈ R2. (17)

where d ∈ R2 is the displacement between the pixel center and the 2D Gaussian center.

For the 2D covariance, we have

∂σn ∂Σn

= −

- 1

- 2

Σ−n1dnd⊤n Σ−n1 ∈ R2×2. (18)

For detailed derivation of the gradient with respect to the 2D covariance, please refer to [71].

- A.2 Gradients of 2D Gaussian Formation Firstly, for the Cholesky decomposition, we have

Σ = LL⊤,L =

l1 0 l2 l3

. (19)

Let G = ∂∂ΣL =

- g1 g2
- g2 g3

, we then derive the gradiants of l1, l2 and l3.

For l1, we have

∂L ∂l1

∂L ∂Σ

= ⟨

,

∂Σ ∂l1 ⟩ =

For l2, we have

- g1 g2
- g2 g3

2l1 l2 l2 0

= 2g1l1 + 2g2l2. (20)

∂L ∂l2

∂L ∂Σ

= ⟨

,

∂Σ ∂l2 ⟩ =

For l3, we have

- g1 g2
- g2 g3

0 l1 l1 2l2

= 2g2l1 + g2l2. (21)

∂L ∂l3

∂L ∂Σ

= ⟨

,

∂Σ ∂l3 ⟩ =

- g1 g2
- g2 g3

0 0 0 2l3

= 2g3l3. (22)

Secondly, for the rotation-scaling (RS) decomposition, we have

Σ = RSS⊤R⊤,R =

cosθ −sinθ sinθ cosθ

,S =

s1 0 0 s2

. (23)

For θ, we have

where

∂L ∂θ

∂L ∂Σ

= ⟨

,

∂Σ ∂θ ⟩ =

- g1 g2
- g2 g3

∂R ∂θ

= −sinθ −cosθ cosθ −sinθ

- For s1, we have ∂L

∂s1

=

∂L ∂s21

∂s21 ∂s1

=

∂L ∂s21

2s1 = R

2s1 0 0 0

R⊤. (26)

- For s2, we have

∂s22 ∂s2

∂L ∂s2

∂L ∂s22

=

=

∂L ∂s21

∂R⊤ ∂θ

∂R ∂θ

SS⊤R⊤ + RSS⊤

). (24)

(

∂R⊤ ∂θ

= −sinθ cosθ −cosθ −sinθ

,

. (25)

2s2 = R

0 0 0 2s2

R⊤. (27)

### B Details of Partial Bits-Back Coding

In Fig. 4 of Section 4.2, we show the results of our codec ("Ours"), alone with two variants using bits-back coding ("Ours+BB", "Ours-Bound"). The "Ours" is the original GaussianImage codec without any bits-back coding. It is the practical codec that achieves 2000 FPS. The "Ours+BB" is the partial bits-back coding codec described in Section 3.3. It reduces a bitrate of

log(N − K)! − log(N − K) (28)

- Algorithm 1 Partial Bits-Back Coding Encode

input the 2D Gaussian parameters G[1 : N]. procedure Partial-Bits-Back-Encode(G[1 : N]) m ← ∅ for K = 1 to N do

m ← ans-encode(m, G[K]) {Rate +RK } if len(m) ≥ log(N − K)! then

##### break

end if end for m, G[K + 1 : N] ← ans-decode(m, U(N−K)!, G[K + 1 : N]) {Rate − log(N − K)!} m ← ans-encode(m, G[K + 1 : N]) {Rate + Ni=K+1 Ri} m ← ans-encode(m, N − K) {Rate + log(N − K)} return m

from the original GaussianImage codec. And K is selected as the lowerbound of previous K 2D Gaussian whose cumulative bitrate is at least log(N −K)!:

K

K∗ = inf K,s.t.

Rk ≥ log(N − K)!. (29)

k=1

This rate reduction is introduced in [37], and can be implemented using a first in last out entropy coder named Asymmetric Numeral Systems (ANS) [21]. The encoding procedure has a sub-procedure of decoding, and the decoding procedure has a sub-procedure of encoding [60]. The general process of partial bits-back coding is described in Algorithm 1 and 2, where Ud is uniform distribution with d elements.

When applied to a whole dataset, the partial bits-back coding becomes unnecessary. More specifically, we no longer require encoding previous K Gaussian for initial bits. Instead, we can just use previous image as initial bits. In that case, we can just follow the vanilla bits-back coding in [60]. For a dataset with infinite images, the average rate reduction is

log N! − log N. (30)

However, this rate reduction is never achieved as dataset is never infinite. While it is indeed the greatest lowerbound as any rate greater is achievable. Or to say, the greatest lowerbound of rate for bits-back coding is not achievable. Therefore, we name it "Ours-Bound".

### C Experiments

#### C.1 Implementation Details

GaussianImage. During the formation of 2D Gaussian, we apply the tanh function to limit the range of position parameters to (-1,1). For covariance parameters, we add 0.5 to the diagonal elements l1,l3 of the lower triangular matrix

- Algorithm 2 Partial Bits-Back Coding Decode

input the bitstream m. procedure Partial-Bits-Back-Decode(m) m, N − K ← ans-decode(m) m, G[K + 1 : N] ← ans-decode(m) m, G[K + 1 : N] ← ans-encode(m, U(N−K)!, G[K + 1 : N]) m, G[1 : K] ← ans-decode(m) return G[1:K]

L in the Cholesky factorization or the scaling elements s1,s2 in the rotationalscaling factorization. This adjustment prevents the scaling of the covariance from becoming excessively small. In addition, the covariance parameters and weighted color coefficients are initialized using a uniform distribution. The position parameters are initialized as follows:

µ = atanh(rand(2) ∗ 2 − 1). (31) where rand(n) generates n random numbers from a uniform distribution.

Baselines. For SIREN [54] and WIRE [53], we implement them by using the open-source project1 from WIRE. For I-NGP [48] and NeuRBF [18], we adopt the project2 from NeuRBF. As for compression baselines, the implementation of COIN [23] uses their library3. We evaluate the VAE-based codecs (Ballé17 [5], Ballé18 [6]) using the MSE-optimized models provided by CompressAI [9]. It is worth noting that during the inference of the INR methods, we sample all image coordinates at once to output the corresponding RGB values. This is the maximum inference speed that the INR methods can achieve when the GPU memory resources are sufficient.

#### C.2 Image Representation and Compression

As shown in Fig. 6, we provide performance comparisons of image representation and compression on DIV2K and Kodak datasets, respectively.

#### C.3 Ablation Study

Number of Gaussians. As shown in Fig. 7, our proposed methods improve the quality of the fitted image as the number of Gaussians increases.

Effect of additive operation. The additive operation can be seen as convolving the covariance matrix with a continuous Gaussian, which helps antialiasing, thereby effectively improving the fitting performance, as illustrated in Table 5.

- 1 https://github.com/vishwa91/wire
- 2 https://github.com/oppo-us-research/NeuRBF
- 3 https://github.com/EmilienDupont/coin

DIV2K Dataset (Representation)

Kodak Dataset (Compression)

40

36

38

34

36

32

PSNR(dB)

PSNR(dB)

34

30

28

32

26

30

WIRE

3D GS

JPEG

Balle18

SIREN

I-NGP

JPEG2000

COIN Ours

24

NeuRBF

Ours

Balle17

28

10 3 10 2 10 1 Decoding Time (s)

10 3 10 2 10 1 Decoding Time (s)

###### Fig. 6: Image representation (left) and compression (right) results with different decoding time on the DIV2K and Kodak dataset, respectively. The radius of each point indicates the parameter size (left) or bits per pixel (right). Our method enjoys the fastest decoding speed regardless of parameter size or bpp.

Kodak Dataset

DIV2K Dataset

38

42

36

40

34

38

PSNR(dB)

PSNR(dB)

36

32

34

30

32

Ours-Cholesky

Ours-Cholesky

28

Ours-RS

Ours-RS

30

5k 10k 15k 20k 25k 30k 35k 40k 45k 50k Number of Gaussians

5k 10k 15k 20k 25k 30k 35k 40k 45k 50k Number of Gaussians

Fig. 7: Image representation with different number of Gaussians.

Robustness in different factorized forms. Fig. 8 highlights the application of identical quantization approaches to various factorized forms. Notably, the RS codec variant underperforms the Cholesky codec variant, suggesting that rotation and scaling parameters are particularly susceptible to compression distortions, which requires carefully tailored specialized quantization strategies to achieve efficient compression.

### D Discussion

In this paper, we simply apply existing compression techniques to build our image codec. As depicted in Fig. 4 in the main paper, there remains a considerable discrepancy between our codec and existing traditional/VAE-based codecs in the compression performance. This gap indicates an imperative need for the development of specialized compression algorithms tailored for Gaussian-based codecs

Table 5: Ablation study of additive operation on Kodak and DIV2K datasets with 30000 Gaussian points over 50000 training steps.

Kodak DIV2K PSNR MS-SSIM PSNR MS-SSIM

Variants

Ours-Cholesky + w/ add 0.5 38.57 0.9961 34.51 0.9924 Ours-Cholesky + w/o add 0.5 35.05 0.9906 31.63 0.9830

Ours-RS + w/ add 0.5 38.83 0.9964 34.64 0.9927 Ours-RS + w/o add 0.5 36.34 0.9930 32.51 0.9859

Kodak Dataset

DIV2K Dataset

- 24

- 25

- 26

- 27

- 28

- 29

- 23

- 24

- 25

- 26

- 27

- 28

- 29

- 30

PSNR(dB)

PSNR(dB)

COIN++

COIN

COIN

Ours-Cholesky

Ours-Cholesky

Ours-RS

Ours-RS

0.2 0.4 0.6 0.8 1.0 1.2 Bpp

0.2 0.4 0.6 0.8 1.0 Bpp

Fig. 8: Image compression results with different factorized forms on the Kodak and DIV2K dataset, respectively.

to elevate the performance. Moreover, as shown in Table 2 in the main paper, although our encoding speed has been improved by three orders of magnitude compared with COIN [23], there is still a gap of four orders of magnitude compared with VAE-based codecs [5,6]. Therefore, exploring avenues for more rapid image fitting and Gaussian compression emerges as a critical research direction.

Considering that our GaussianImage provides an explicit representation and coding of images, we will further investigate this line from various aspects in the future. First, recent literature successfully performs segmentation-based textguided editing on 3D scene represented by Gaussians [16,24], since this discrete representation naturally provides a semantics layout. Intuitively, a similar property also exists in 2D Gaussian images, and it has the potential to develop few-shot text-guided editing on them. Second, image coding for machine [32] is a popular topic in the learned image coding community. This explicit representation is also likely to benefit downstream vision tasks like classification and detection. Finally, high-fidelity image representation [29,45] is also an essential task to delve into.

