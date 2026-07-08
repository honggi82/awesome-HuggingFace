## NeuRBF: A Neural Fields Representation with Adaptive Radial Basis Functions

# arXiv:2309.15426v1[cs.CV]27Sep2023

Zhang Chen1† Zhong Li1† Liangchen Song2 Lele Chen1 Jingyi Yu3 Junsong Yuan2 Yi Xu1 1 OPPO US Research Center 2 University at Buffalo 3 ShanghaiTech University

{zhang.chen,zhong.li,lele.chen,yi.xu}@oppo.com {lsong8,jsyuan}@buffalo.edu yujingyi@shanghaitech.edu.cn https://oppo-us-research.github.io/NeuRBF-website/

### Abstract

We present a novel type of neural fields that uses general radial bases for signal representation. State-of-the-art neural fields typically rely on grid-based representations for storing local neural features and N-dimensional linear kernels for interpolating features at continuous query points. The spatial positions of their neural features are fixed on grid nodes and cannot well adapt to target signals. Our method instead builds upon general radial bases with flexible kernel position and shape, which have higher spatial adaptivity and can more closely fit target signals. To further improve the channel-wise capacity of radial basis functions, we propose to compose them with multi-frequency sinusoid functions. This technique extends a radial basis to multiple Fourier radial bases of different frequency bands without requiring extra parameters, facilitating the representation of details. Moreover, by marrying adaptive radial bases with grid-based ones, our hybrid combination inherits both adaptivity and interpolation smoothness. We carefully designed weighting schemes to let radial bases adapt to different types of signals effectively. Our experiments on 2D image and 3D signed distance field representation demonstrate the higher accuracy and compactness of our method than prior arts. When applied to neural radiance field reconstruction, our method achieves state-of-the-art rendering quality, with small model size and comparable training speed.

### 1. Introduction

Neural fields (also termed implicit neural representation) have gained much popularity in recent years due to their effectiveness in representing 2D images, 3D shapes, radiance fields, etc. [50, 44, 15, 70, 62, 47, 48]. Compared to tra-

† Corresponding author.

SDF NeRF

[Figure 1]

[Figure 2]

|[Figure 3]|
|---|

|[Figure 4]|
|---|

|[Figure 5]|
|---|

|[Figure 6]|
|---|

[Figure 7]

Gigapixel Image

Figure 1. NeuRBF provides an accurate and compact neural fields representation for 2D images, 3D SDF, and neural radiance fields.

ditional discrete signal representations, neural fields utilize neural networks to establish a mapping from continuous input coordinates to the corresponding output value. Owing to their concise and efficient formulation, neural fields have been applied to various areas ranging from signal compression [66, 22, 12, 86], 3D reconstruction [49, 83, 79], neural rendering [47, 48, 9, 39, 63, 25, 64, 14], medical imaging [24, 81, 75], acoustic synthesis [11] and climate prediction [31].

Early neural fields [50, 44, 15, 47] use neural features that are globally shared in the input domain. Despite the compactness of the models, they have difficulty in representing high-frequency details due to the inductive bias [5, 70] of MLPs. To tackle this problem, local neural fields have been proposed and widely adopted [7, 32, 51, 41, 26, 67, 48, 9], where each local region in the input domain is assigned with different neural features. A common characteristic in this line of work is to use explicit grid-like structures to spatially organize neural features and apply N-dimensional linear interpolation to aggregate local neural features. However, grid-like structures are not adaptive to the target signals and cannot fully exploit the non-uniformity and sparsity in various tasks, leading to

potentially sub-optimal accuracy and compactness. While multi-resolution techniques [69, 16, 58, 84, 28] have been explored, it can still be expensive to achieve fine granularity with excessive resolution levels. Some works [47, 70, 62] use frequency encoding to address the low-frequency inductive bias. However, this technique is only applied on either input coordinates or deep features.

In this work, we aim to increase the representation accuracy and compactness of neural fields by equipping the interpolation of basis functions with both spatial adaptivity and frequency extension. We observe that the gridbased linear interpolation, which is the fundamental building block in state-of-the-art local neural fields, is a special case of radial basis function (RBF). While grid-based structures typically grow quadratically or cubically, general RBFs can require fewer parameters (sometimes even constant number) to represent patterns such as lines and ellipsoids. Based upon this observation, we propose NeuRBF, which comprises of a combination of adaptive RBFs and grid-based RBFs. The former uses general anisotropic kernel function with high adaptivity while the latter uses Ndimensional linear kernel function to provide interpolation smoothness.

To further enhance the representation capability of RBFs, we propose to extend them channel-wise and compose them with multi-frequency sinusoid function. This allows each RBF to encode a wider range of frequencies without requiring extra parameters. This multi-frequency encoding technique is also applicable to the features in the MLP, which further improves accuracy and compactness.

To effectively adapt radial bases to target signals, we adopt the weighted variant of K-Means to initialize their kernel parameters, and design a weighting scheme for each of the three tasks (see Fig. 1): 2D image fitting, 3D signed distance field (SDF) reconstruction, and neural radiance field (NeRF) reconstruction. For NeRF, since it involves indirect supervision, traditional K-Means cannot be directly applied. To address this, we further propose a distillationbased approach.

In summary, our work has the following contributions:

- • We present a general framework for neural fields based on radial basis functions and propose a hybrid combination of adaptive RBFs and grid-based RBFs.
- • We extend radial bases with multi-frequency sinusoidal composition, which substantially enhances their representation ability.
- • To effectively adapt RBFs to different target signals, we devise tailored weighting schemes for K-Means and a distillation-based approach.
- • Extensive experiments demonstrate that our method achieves state-of-the-art accuracy and compactness on

2D image fitting, 3D signed distance field reconstruction, and neural radiance field reconstruction.

### 2. Related Work

Global Neural Fields. Early neural fields [50, 44, 15, 77, 45, 21] are global ones and primarily focus on representing the signed distance field (SDF) of 3D shapes. They directly use spatial coordinates as input to multi-layer perceptrons (MLPs) and optionally concatenate a global latent vector for generalized or generative learning. These methods have concise formulation and demonstrate superior flexibility over convolutional neural networks (CNN) and traditional discrete representations in modeling signals in the continuous domain. However, these methods are unable to preserve the high-frequency details in target signals.

Mildenhall et al. [47] pioneeringly proposed NeRF, which incorporates neural fields with volumetric rendering for novel view synthesis. They further apply sine transform to the input coordinates (i.e., positional encoding), enabling neural fields to better represent high-frequency details. Similar ideas are also adopted in RFF [70] and SIREN [62], which use random Fourier features or periodic activation as frequency encoding. These works also promote neural fields to be a general neural representation applicable to different types of signals and tasks. More recently, other encoding functions or architectures have been explored [23, 72, 40, 60, 74, 73, 19, 36, 87, 52, 53, 18, 85, 57, 80]. For example, MFN [23] replaces MLPs with the multiplication of multiple linear functions of Fourier or Gabor basis functions, and WIRE [57] uses Gabor wavelet as activation function in MLPs. Radial basis functions (RBF) have also been discussed in [52, 53]. However, unlike our work, they only consider simplified forms of RBFs and do not explore spatial adaptivity, leading to nonideal performance.

Local Neural Fields. In parallel to frequency encoding, local neural fields improve representation accuracy by locality. Early attempts [7, 32, 51, 17, 13, 67] uniformly subdivide the input domain into dense grids and assign a neural feature vector to each grid cell. During point querying, these local neural features are aggregated through nearestneighbor or N-dimensional linear interpolation and then used as input to the following MLPs. Due to feature locality, the depth and width of the MLPs can be largely reduced [67, 26, 33], leading to higher training and inference speed than global neural fields. Apart from neural features, the locality can also be implemented on the network weights and biases [54, 58, 29], where each grid cell has a different MLP. Dense grids can be further combined with RFF [70] or SIREN [62] to improve accuracy on high-frequency details [30, 43]. However, a significant drawback of dense grids is that they are parameter-intensive.

[Figure 8]

[Figure 9]

[Figure 10]

[Figure 11]

| |
|---|

[Figure 12]

[Figure 13]

[Figure 14]

RGB SDF Density …

[Figure 15]

| |
|---|

| |
|---|

[Figure 16]

Feature Aggregation

Adaptive RBFs Multi-Frequency MLP Network Sinusoidal Composition

- Figure 2. Illustration of NeuRBF. Each adaptive RBFs can have different position and shape parameters ci, Σi, leading to high spatial adaptivity. With multi-frequency sinusoidal composition, each adaptive RBF is further extended to multiple radial bases with different frequencies, which are then combined with neural features wi through Hadamard product. The resulting features are aggregated within the neighborhood U(x) of query point x, and then be mapped to the output domain by the MLP network gm.

gb(x) = i∈U(x) φ(x,ci)wi. U(x) is the set of grid corner nodes that enclose x, ci ∈ RD and wi ∈ RF are the position and neural feature of node i. φ(x,ci) ∈ R is the interpolation weight of node i, and is computed as:

To improve model compactness, numerous techniques have been proposed, such as multi-resolution tree (and/or residual) structures [41, 84, 16, 42, 58, 82, 76, 26], hash grids [48], dictionary optimization [68], permutohedral lattices [56], tensor decomposition [9], orthogonal planes [51, 8, 61, 6, 25], wavelet [55], and multiplicative fields composition [10]. Among them, Instant NGP [48] achieves high accuracy, compactness, and efficiency across different signal types. Despite the additional data structures or operations, these methods still rely on basic grid-based linear interpolation as the building block for neural feature aggregation. Another line of work [27, 38, 78] relaxes the grid structures and allows neural features to be freely positioned in the input domain. However, they use simple interpolation kernel functions, which still have limited spatial adaptivity. Their performance is also inferior to state-of-the-art gridbased ones.

D

|xj − ci,j| σ

), (1)

max(0,1 −

φ(x,ci) =

j=1

where σ is the sidelength of each grid cell, and xj,ci,j are the jth element of x,ci. Note that Eq. (1) is a special case of radial basis function (RBF) with the form of φ(x,ci,σi), where each RBF has its own position parameter ci and shape parameter σi. From the perspective of RBF, we use the following formulation for gb(x):

φ(x,ci,σi)wi. (2)

gb(x) =

i∈U(x)

Unlike prior local neural fields, we seek a general framework consisting of hybrid radial bases and enhance their representation capability by simultaneously exploiting spatial adaptivity and frequency extension.

#### 3.2. Neural Radial Basis Fields

Compared to grid-based linear interpolation, the advantages of RBFs originate from the additional position and shape parameters ci,σi. As illustrated in Fig. 2, our framework makes extensive use of adaptive RBFs. To fully exploit their adaptivity, we propose to use anisotropic shape parameters Σi ∈ RD×D. The first row of Fig. 3 shows that with anisotropic shape parameters, the shape of an RBF’s level set can be either circular, elliptical, or even close to a line. This allows an RBF to be more adaptive to target signals. For the kernel function φ, we use the inverse quadratic function as an example, which is computed as:

### 3. Our Method

#### 3.1. Local Neural Fields As Radial Basis Functions

Local neural fields represent a signal f in the form of a function fˆ : RD → RO, which maps a coordinate x in the continuous D-dimensional space to an output of O dimensions. The function f can be considered as a composition of two stages, i.e., f = gm ◦ gb, where gb extracts the local neural features at input location x from a neural representation (e.g., feature grid), and gm decodes the resulting feature to the final output. Now we consider grid-based linear interpolation for gb, which is a common building block in state-of-the-art neural fields. It has the following form:

1 1 + (x − ci)TΣ−i 1(x − ci)

. (3)

φ(x,ci,Σi) =

Note that Σi is a covariance matrix, which is symmetric. Hence, each Σi only has D·(D2−1) parameters. We can op-

Our sinusoidal composition technique differs from positional encoding [47] and random Fourier features [70] in that we apply sine transform to radial bases instead of input coordinates. This allows the composited bases to have elliptical periodic patterns as shown in Fig. 3 second row, while the bases created by [47, 70] are limited to linear periodic patterns. Our technique is also related to the Gabor filter, which combines a Gaussian function and a sinusoidal function using multiplication. Still, the Gabor filter can only produce bases with linear patterns.

Fourier Basis Radial Bases

[Figure 17]

[Figure 18]

[Figure 19]

[Figure 20]

[Figure 21]

[Figure 22]

[Figure 23]

[Figure 24]

[Figure 25]

Gabor Basis Extended Radial Bases

- Figure 3. Comparison of Bases. For the right 3 columns: the first row shows radial bases with different shape parameters; the bottom row shows extended radial bases with different frequencies.

Sinusoidal Composition on Feature Vector. We also apply our sinusoidal composition technique to the output features h0 of the first fully-connected (FC) layer in gm:

f0 = sin(h0 ⊙ m0) + h0, (7) where h0,m0,f0 ∈ RF

tionally normalize the radial basis value at each point:

0 and ⊙ is Hadamard product. The bias term is omitted since it is already contained in FC layer. The reason to apply this sinusoidal composition to h0 instead of gb(x) is to let the network first combines the multifrequency bases in gb(x) via an FC layer. Here, we also include a residual connection, which slightly benefits performance. The resulting feature vector f0 is input to the next layer in gm. m0 is set in a similar manner as m by specifying its lowest and highest frequency ml0 and mh0.

φ(x,ci,Σi) k∈U(x) φ(x,ck,Σk)

. (4)

φ˜(x,ci,Σi) =

Note that our framework is not limited to a specific function type but supports any others that have the radial basis form. The choice of the function type can thus be finetuned per task.

Sinusoidal Composition on Radial Basis. We notice that while traditional RBF is a scalar function, wi ∈ RF is a vector with multiple channels (recall Eq. (2)). Our motivation is to let each channel of wi linearly combine with a different variant of the RBF so that the channel-wise capacity of RBF can be exploited. To achieve this, we propose to compose RBF with a multi-frequency sinusoid function, where a radial basis is extended into multiple channels with different frequencies:

Compared to sinusoid activation [62], our multifrequency approach can produce features of wide frequency range with one sine transform. In addition, it does not require specialized initialization for the FC layers. We experimentally observe that our technique achieves higher performance under radial basis framework. Table 5 shows a quantitative comparison with positional encoding [47] and sinusoid activation [62].

φ(x,ci,Σi) = sin(˜φ(x,ci,Σi) · m + b), (5)

Hybrid Radial Bases. To balance between fitting accuracy and interpolation smoothness, we propose to use a combination of adaptive RBFs and grid-based RBFs. The position and shape parameters of adaptive RBFs can be freely assigned while those of grid-based RBFs are fixed to a grid structure. Adaptive RBFs tend to produce sharp discontinuities when U(x) (the set of neighboring RBFs of the point x) changes. On the other hand, grid-based RBFs do not exhibit such discontinuity and can better preserve function smoothness. Please refer to our supplementary for an illustration. We combine adaptive and grid-based RBFs through feature concatenation, which allows the network to select features accordingly.

where m,b ∈ RF are the global multiplier and bias applied to φ˜(x,ci,Σi) before sine transform. The resulting φ(x,ci,Σi) has F channels and is then multiplied with wi through Hadamard product. Fig. 2 illustrates this computation process. gb(x) is thus computed as:

φ(x,ci,Σi) ⊙ wi. (6)

gb(x) =

i∈U(x)

With Eq. (5), the number of bases encoded by a single pair of ci,Σi is increased from 1 to F, leading to higher representation ability. Note that m,b are globally shared across RBFs. We set b as a learnable parameter and m as a fixed parameter. We determine the value of m by specifying the lowest and highest frequencies ml,mh. The rest of the elements are obtained by log-linearly dividing the range between ml and mh.

#### 3.3. Initialization of Position and Shape Parameters

Motivated by [59], we adapt RBFs to target signals by initializing their position and shape parameters with weighted K-Means clustering. Intuitively, this biases RBF

distribution towards data points with higher weights. This technique is simple and effective, and can be applied to different tasks by changing the weighting scheme.

Position Initialization. Let x1,...,xm be the coordinates of input points and w1,...,wm be the weight of each point (weight calculation will be described later). Given initial cluster centers c1,...,cn, weighted K-Means optimizes these cluster centers with:

n

min

c1,...,cn

i=1

m

aijwj∥xj − ci∥2, (8)

j=1

where aij is an indicator variable. Following common practice, we solve Eq. (8) with an expectation–maximization (EM)-style algorithm.

Shape Initialization. Inspired by Gaussian mixture model, we initialize the shape parameters Σi as the following:

aijwj(xj − ci)(xj − ci)T j aijwj

Σi = j

. (9)

Weighting Schemes. The weights w1,...,wm control how RBFs will be distributed after initialization. Data points with higher importance should be assigned with higher weights.

- For 2D images, we use the spatial gradient norm of pixel

value as the weight for each point: wj = ∥∇I(xj)∥.

- For 3D signed distance field, we use the inverse of abso-

lute SDF value as point weight: wj = 1 / (|SDF(xj)| + 1e−9). The inclusion of 1e−9 is to avoid division by zero.

For neural radiance field, it is a task with indirect supervision. The input signal is a set of multi-view 2D images while the signal to be reconstructed lies in 3D space. Therefore, we cannot directly obtain the weights. To tackle this problem, we propose a distillation method. We first use grid-based neural fields to train a model for 1000 ∼ 2000 training steps. Then we uniformly sample 3D points and use the trained model to predict the density σ(x) and color feature vector fc(x) at these points. Finally, we convert density to alpha and multiply with the spatial gradient norm of the color feature vector as point weight: wj = (1−exp(−σ(xj)δ))∥∇fc(xj)∥. This weighting scheme takes both density and appearance complexity into account. Compared to 3D Gaussian Splatting [34] and Point-NeRF [78], our approach does not require external structure-from-motion or multi-view stereo methods to reconstruct the point cloud, but distills information from a volumetric model. Hence, our initialization can handle both surface-based objects and volumetric objects.

### 4. Implementation

In this section, we describe the keypoints of our implementation. More details can be found in our supplementary.

We implement our adaptive RBFs using vanilla PyTorch without custom CUDA kernels. For the grid-based part in our framework, we adopt Instant NGP [48] for 2D image fitting and 3D signed distance field (SDF). We use a PyTorch implementation of Instant NGP from [1]. For neural radiance field (NeRF) reconstruction, we explored TensoRF [9] and K-Planes [25] as the grid-based part. We reduce the spatial resolution and feature channel of the grid-based part, and allocate parameters to the adaptive RBFs accordingly.

For sinusoidal composition, we use ml = 2−3,mh = 212,ml0 = 1,mh0 = 1000 in the image experiments on DIV2K dataset [3, 71], and ml = 20,mh = 23,ml0 = 30,mh0 = 300 in SDF experiments. In NeRF task, we do not apply sinusoidal composition since the improvement is small.

Training is conducted on a single NVIDIA RTX A6000 GPU. We use Adam optimizer [35] where β1 = 0.9,β2 = 0.99,ϵ = 10−15. The learning rates for neural features are 5×10−3,1×10−4,2×10−2 for image, SDF and NeRF task respectively. In addition, we apply learning rate schedulers that gradually decrease learning rates during training. The position and shape parameters of RBFs can be optionally finetuned via gradient backpropagation. However, we do not observe significant performance gain and therefore fix these parameters during training.

We use L2 loss when fitting 2D images and reconstructing neural radiance field, and use MAPE loss [48] when reconstructing 3D SDF. For SDF task, we use the same point sampling approach as Instant NGP [48]. For NeRF task, we follow the training approaches in TensoRF [9] and KPlanes [25] respectively. In all experiments, both competing methods and our method are trained per scene.

### 5. Experiment 5.1. 2D Image Fitting

We first evaluate the effectiveness of fitting 2D images. We use the validation split of DIV2K dataset [3, 71] and

###### 6 additional images of ultra-high resolution as evaluation benchmark. DIV2K validation set contains 100 natural images with resolution around 2040 × 1356. The resolution of the 6 additional images ranges from 6114 × 3734 to 56718 × 21450.

We first compare with MINER [58] and Instant NGP (“INGP”) [48], which exhibit state-of-the-art performance for high-resolution image fitting. We let our method use fewer parameters than the other two. During timing, the time for initializing RBFs is also taken into account.

Table 1 top half shows the comparison on the DIV2K dataset. For our method, we include two additional setups:

Steps Time↓ # Tr. Params↓ PSNR↑

DIV2K MINER [58] 35k 16.7m 5.49M 46.92 I-NGP [48] 35k 1.3m 4.91M 47.56 Ours 35k 7.9m 4.31M 58.56 Ours3.5k−steps 3.5k 48s 4.31M 51.53 Ours2.2M 35k 7.7m 2.20M 49.26 DIV2K 256×256×3

BACON [40] 5k 78.2s 268K 38.51 PNF [80] 5k 483.9s 287K 38.99 Ours 5k 28.5s 128K 54.84

- Table 1. 2D Image Fitting. We quantitatively compare our method with MINER [58], Instant NGP (“I-NGP”) [48], BACON [40] and PNF [80] on the validation set of DIV2K dataset [3, 71]. “DIV2K”: original image resolution; “DIV2K 256×256×3”: center cropped and downsampled to 256×256×3.

MINER Instant NGP Ours

[Figure 26]

[Figure 27]

[Figure 28]

[Figure 29]

0.01

[Figure 30]

6114 × 3734 × 3

# Tr. Params↓ : 43.87M PSNR↑ : 51.77 dB

37.15M 50.89 dB

34.62M 60.52 dB

[Figure 31]

[Figure 32]

[Figure 33]

[Figure 34]

0

8000 × 8000 × 3

67.24M 50.66 dB

61.45M 48.53 dB

57.46M 53.86 dB

- Figure 4. 2D Image Fitting. Leftmost column shows the fitted images of our method and the resolution of the images. The other columns show the error maps of each method, along with the number of trainable parameters (“# Tr. Params”) and PSNR.

one using fewer training steps and one using fewer trainable parameters. When using the same number of training steps, our method outperforms the other two by over 10 dB in Peak Signal-to-Noise Ratio (PSNR) with less trainable parameters. Although Instant NGP has faster training speed due to their heavily-optimized CUDA implementation, our method is implemented with vanilla PyTorch and is easily extensible. In addition, with only 3.5k training steps (1/10 of that of Instant NGP), our method already reaches a PSNR of 51.53 dB, which is almost 4 dB higher than Instant NGP. Meanwhile, the training time is only 48s and even faster than Instant NGP. The time for RBF initialization is around 2s. “Ours2.2M” additionally demonstrates the high compactness of our method. After reducing trainable parameters to be over 50% fewer than the competing methods, our approach still retains a higher fitting accuracy.

In Fig. 4, we show the fitting results on 2 ultra-high resolution images. Besides achieving higher PSNR than the other two, our method also has a more uniform error distri-

GT Ours BACON PNF

[Figure 35]

[Figure 36]

[Figure 37]

[Figure 38]

[Figure 39]

[Figure 40]

[Figure 41]

[Figure 42]

| |
|---|

[Figure 43]

[Figure 44]

[Figure 45]

[Figure 46]

| |
|---|

# Params↓ / PSNR↑ 268K / 40.74 287K / 40.86

128K / 50.34

- (a)
- (b)

Ours I-NGP MINER BACON PNF

[Figure 47]

[Figure 48]

[Figure 49]

[Figure 50]

[Figure 51]

[Figure 52]

[Figure 53]

[Figure 54]

[Figure 55]

[Figure 56]

[Figure 57]

[Figure 58]

[Figure 59]

[Figure 60]

[Figure 61]

2500500100

Steps

- (c)

[Figure 62]

Figure 5. 2D Image Fitting on an image from Kodak dataset [20]. (a) Final results after 5k training steps. (b) Training curves. (c) Intermediate results.

bution. This reflects the adaptivity of RBFs, which allows a more accurate representation of details. Results on other images can be found in our supplementary material.

We additionally compare with BACON [40] and PNF [80] on the 100 images in DIV2K validation set. In this experiment, the images are center cropped and downsampled to 256×256×3 following the practice of BACON [40]. We use their official codes and settings for BACON and PNF, and let our method use the same batch size (65,536) and training steps (5k) as them. The results are shown in Table 1 bottom half. We further conduct comparisons on a sample image from Kodak dataset [20], and show the qualitative results and training curves in Fig. 5. The image is similarly center cropped and resized to 256×256×3. The results show that our method has both fast convergence and high fitting accuracy. Higher PSNR demonstrates the ability to more precisely represent target signals, and implies fewer parameters and training steps to reach a specified PSNR. For the image in Fig. 5, Instant NGP and MINER reach 45.34 dB and 45.23 dB PSNR with 140K parameters and 5k steps. Our method instead can reach 45.59 dB PSNR with only 72K parameters and 3.5k steps.

NGLOD6 Instant NGP Ours GT

[Figure 63]

|[Figure 64]|
|---|

|[Figure 65]|
|---|

|[Figure 66]|
|---|

|[Figure 67]|
|---|

[Figure 68]

# Tr. Params↓ : 78.84M NAE↓ : 14.64°

1.80M 10.09°

1.62M 9.23°

|[Figure 69]|
|---|

|[Figure 70]|
|---|

|[Figure 71]|
|---|

|[Figure 72]|
|---|

78.84M 6.46°

950K 6.00°

856K 5.30°

Figure 6. 3D Signed Distance Field Reconstruction. Leftmost column shows the reconstructed geometry of our method. The other columns show qualitative and quantitative comparisons of reconstruction results. “# Tr. Params” is the number of trainable parameters and “NAE” is the normal angular error.

|[Figure 73]|
|---|

|[Figure 74]|
|---|

|[Figure 75]|
|---|

|[Figure 76]|
|---|

Steps # Tr. Params↓ IoU↑ NAE↓

I-NGPOurs

NGLOD5 [69] 245k 10.15M 0.9962 6.58 NGLOD6 [69] 245k 78.84M 0.9963 6.14 I-NGP [48] 20k 950K 0.9994 5.70 Ours 20k 856K 0.9995 4.93

# Tr. Params↓ : 137K NAE↓ : 4.93°

260K 4.11°

498K 3.20°

GT

I-NGP400K [48] 20k 498K 0.9992 6.39 Ours400K 20k 448K 0.9994 5.53

|[Figure 77]|
|---|

|[Figure 78]|
|---|

|[Figure 79]|
|---|

|[Figure 80]|
|---|

- Table 2. 3D Signed Distance Field Reconstruction. We quantitatively compare our method with NGLOD [69] and Instant NGP (“I-NGP”) [48].

124K 3.75°

235K 3.13°

448K 2.89°

#### 5.2. 3D Signed Distance Field Reconstruction

Figure 7. 3D Signed Distance Field Reconstruction. We compare the reconstruction accuracy of Instant NGP (“I-NGP”) [48] and ours under different parameter count.

We use 10 3D models from the Stanford 3D Scanning Repository [65], the Digital Michelangelo Project [37], and TurboSquid [2] as benchmark data. These models contain delicate geometric details and challenging topologies. We compare our method with NGLOD [69] and Instant NGP [48]. For evaluation metrics, we use Intersection over Union (IoU) and normal angular error (NAE). NAE measures the face normal difference of corresponding points and can better reflect the accuracy of reconstructed surface than IoU.

#### 5.3. Neural Radiance Field Reconstruction

We evaluate our approach on both 360◦ scenes and forward-facing scenes. Metrics of the comparison methods are taken from their paper whenever available. Full perscene results are available in our supplementary material.

Fig. 6 demonstrates example results on 3 objects. Our method produces more accurate geometry, with sharp edges and smooth surfaces. Comparatively, the results of NGLOD are overly smooth while those of Instant NGP contain noises.

360◦ Scenes. We use the Synthetic NeRF dataset [47] which is a widely adopted benchmark for neural radiance field reconstruction. We utilize TensoRF [9] as the gridbased part in this experiment. We compare with numerous representative methods in this area, as listed in Table 3. Among them, Instant NGP [48] and TensoRF [9] represent state-of-the-art performance while Factor Fields [10] is concurrent to our work. For Point-NeRF [78], their SSIM metrics are recomputed with a consistent SSIM implementation as other work.

In Table 2, we compare the performance under different numbers of trainable parameters. Our approach consistently has higher IoU and lower NAE. The advantages of our method are larger when using fewer parameters, which is also demonstrated in Fig. 7.

Batch Size Steps Time↓ # Params↓ PSNR↑ SSIM↑ LPIPSV GG ↓ LPIPSAlex ↓ NeRF [47] 4096 300k ∼ 35h 1.25M 31.01 0.947 0.081 Mip-NeRF 360 [4] 16384 250k ∼ 3.4h 3.23M 33.25 0.962 0.039 Point-NeRF [78] - 200k ∼ 4.5h - 33.31 0.962 0.050 0.028 Plenoxels [26] 5000 128k 11.4m 194.5M 31.71 0.958 0.049 Instant NGP [48] 262144 35k 3.8m 12.21M 33.18 0.963 0.051 0.028 TensoRF [9] 4096 30k 17.4m 17.95M 33.14 0.963 0.047 0.027 Factor Fields [10] 4096 30k 12.2m 5.10M 33.14 0.961 - K-Planes [25] 4096 30k 38m 33M 32.36 0.962 0.048 0.031 Ours 4096 30k 33.6m 17.74M 34.62 0.975 0.034 0.018 Ours3.66M 4096 30k 29.3m 3.66M 33.97 0.971 0.039 0.022

- Table 3. Neural Radiance Field Reconstruction. We quantitatively compare our method with numerous state-of-the-art methods on the Synthetic NeRF dataset [47]. Best 3 scores in each metric are marked with gold , silver and bronze . “-” denotes the information is unavailable in the respective paper.

|[Figure 81]|
|---|

|[Figure 82]|
|---|

|[Figure 83]|
|---|

|[Figure 84]|
|---|

|[Figure 85]|
|---|

|[Figure 86]|
|---|

[Figure 87]

| |
|---|

|[Figure 88]|
|---|

|[Figure 89]|
|---|

|[Figure 90]|
|---|

|[Figure 91]|
|---|

|[Figure 92]|
|---|

|[Figure 93]|
|---|

[Figure 94]

| |
|---|

[Figure 95]

|[Figure 96]|
|---|

|[Figure 97]|
|---|

|[Figure 98]|
|---|

|[Figure 99]|
|---|

|[Figure 100]|
|---|

|[Figure 101]|
|---|

| |
|---|

Point-NeRF Instant NGP TensoRF K-Planes Ours Ground Truth

- Figure 8. Neural Radiance Field Reconstruction. Qualitative comparisons on the Synthetic NeRF Dataset [47]. Leftmost column shows the full-image results of our method.

Table 3 comprehensively compares training time, number of parameters and novel view rendering metrics. Our method surpasses competing methods by a noticeable margin in rendering accuracy. Fig. 8 reflects the higher quality of our results, which contain more accurate details and fewer artifacts. Meanwhile, our method retains a moderate model size (same as TensoRF [9]) and comparable training time. After reducing to 3.66M parameters, our model still achieves high rendering accuracy and outperforms other methods that use more parameters (Plenoxels [26], Instant NGP [48], TensoRF [9], Factor Fields [10], K-Planes [25]). Fig. 9 compares the novel view synthesis accuracy with representative methods (Instant NGP [48], TensoRF [9]) under similar parameter count. Our method consistently performs better than the other two and also achieves higher PSNR

than vanilla NeRF [47] when using the same number of parameters.

Forward-Facing Scenes. We use the LLFF dataset [46] which contains 8 real unbounded forward-facing scenes. In this experiment, we explore using K-Planes [25] as the gridbased part . As shown in Table 4, our approach achieves the highest PSNR and second-best SSIM. Although MipNeRF 360 has a higher score in SSIM, its training time is 7 times longer than ours. Compared to Plenoxels and TensoRF, our method has higher rendering accuracy, fewer parameters and comparable training speed. Fig. 10 shows example novel view synthesis results, where ours contain fewer visual artifacts.

[Figure 102]

2D Images 3D SDF PSNR↑ SSIM↑ IoU↑ NAE↓

No A-RBF 42.37 0.9918 0.9994 5.70 No MSC on RBF 48.19 0.9940 0.9995 5.04 No MSC on Feat. 48.46 0.9935 0.9995 5.09 No MSC on Both 43.81 0.9870 0.9995 5.16 Ours Full 51.53 0.9961 0.9995 4.93

Ours-PE 43.72 0.9870 0.9994 5.46 Ours-SIREN 45.98 0.9920 0.9994 5.69

Table 5. Ablation Study. We ablate on the adaptive RBFs (ARBF) and multi-frequency sinusoidal composition (MSC). “OursPE” replaces MSC with positional encoding [47]. “Ours-SIREN” replaces MSC with sinusoid activation [62].

I-NGP TensoRF Ours I-NGP TensoRF Ours GT

[Figure 103]

[Figure 104]

[Figure 105]

[Figure 106]

[Figure 107]

[Figure 108]

[Figure 109]

steps and all SDF models are trained for 20000 steps. To demonstrate the effectiveness of sinusoidal composition in our framework, we further include variants that replace it with positional encoding [47] (Ours-PE) and sinusoid activation [62] (Ours-SIREN). For Ours-PE, we apply positional encoding [47] (PE) on input coordinate x and concatenate the features with gb(x) before input to the decoder network gm. For Ours-SIREN, we apply sinusoidal activation [62] to the hidden layers in gm, and use the method in [62] to initialize fully-connected layers. As shown in Table 5, without adaptive RBFs and sinusoidal composition, there is a noticeable drop in accuracy. Compared to PE and SIREN, our multi-frequency sinusoidal composition technique achieves higher performance.

# Params: 1M 18M

- Figure 9. Neural Radiance Field Reconstruction. We compare the novel view synthesis quality under different parameter count on the “Materials” scene. Top is a quantitative comparison of rendering PSNR. Bottom is a qualitative comparison between Instant NGP (“I-NGP”) [48], TensoRF [9] and ours at 1M and 18M parameters.

TensoRF K-Planes Ours Ground Truth

[Figure 110]

[Figure 111]

[Figure 112]

[Figure 113]

[Figure 114]

[Figure 115]

[Figure 116]

[Figure 117]

- Figure 10. Neural Radiance Field Reconstruction. Qualitative comparisons on the LLFF Dataset [46].

### 6. Conclusion

We have proposed NeuRBF, which provides accurate and compact neural representations for signals. We demonstrate that by simultaneously exploiting the spatial adaptivity and frequency extension of radial basis functions, the representation ability of neural fields can be greatly enhanced. To effectively adapt radial basis functions to target signals, we further devise tailored weighting schemes. Our method achieves higher accuracy than state-of-the-arts on 2D shape fitting, 3D signed distance field reconstruction, and neural radiance field reconstruction, while using same or fewer parameters. We believe our framework is a valuable step towards more expressive neural representations.

Time↓ # Params↓ PSNR↑ SSIM↑

NeRF [47] 36h 1.25M 26.50 0.811 Mip-NeRF 360 [4] 3.8h 3.23M 26.86 0.858 Plenoxels [26] 24m ∼ 500M 26.29 0.839 TensoRF [9] 25m 45M 26.73 0.839 K-Planes [25] 33m 18.7M 26.92 0.847

Ours 31m 18.7M 27.05 0.849

By far, we have not explored generalized learning, which would be a promising extension of our framework. Another future direction would be incorporating dictionary learning to further increase model compactness.

- Table 4. Neural Radiance Field Reconstruction. Quantitative comparisons on the LLFF Dataset [46].
- 5.4. Ablation Study

### Acknowledgements

In Table 5, we conduct ablation study on adaptive RBFs (A-RBF) and multi-frequency sinusoidal composition (MSC) using the DIV2K validation set [3, 71] and the 3D shapes in Sec. 5.2. All image models are trained for 3500

The authors thank the anonymous reviewers for their valuable feedback, and Anpei Chen and Zexiang Xu for helpful discussions.

### References

- [1] https://github.com/ashawkey/torch-ngp. 5
- [2] https://www.turbosquid.com. 7
- [3] Eirikur Agustsson and Radu Timofte. Ntire 2017 challenge on single image super-resolution: Dataset and study. In The IEEE Conference on Computer Vision and Pattern Recognition (CVPR) Workshops, July 2017. 5, 6, 9, 14, 15
- [4] Jonathan T Barron, Ben Mildenhall, Dor Verbin, Pratul P Srinivasan, and Peter Hedman. Mip-nerf 360: Unbounded anti-aliased neural radiance fields. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 5470–5479, 2022. 8, 9, 21, 24
- [5] Alberto Bietti and Julien Mairal. On the inductive bias of neural tangent kernels. Advances in Neural Information Processing Systems, 32, 2019. 1
- [6] Ang Cao and Justin Johnson. Hexplane: A fast representation for dynamic scenes. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 130–141, 2023. 3
- [7] Rohan Chabra, Jan E Lenssen, Eddy Ilg, Tanner Schmidt, Julian Straub, Steven Lovegrove, and Richard Newcombe. Deep local shapes: Learning local sdf priors for detailed 3d reconstruction. In Computer Vision–ECCV 2020: 16th European Conference, Glasgow, UK, August 23–28, 2020, Proceedings, Part XXIX 16, pages 608–625. Springer, 2020. 1, 2
- [8] Eric R Chan, Connor Z Lin, Matthew A Chan, Koki Nagano, Boxiao Pan, Shalini De Mello, Orazio Gallo, Leonidas J Guibas, Jonathan Tremblay, Sameh Khamis, et al. Efficient geometry-aware 3d generative adversarial networks. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 16123–16133, 2022. 3
- [9] Anpei Chen, Zexiang Xu, Andreas Geiger, Jingyi Yu, and Hao Su. Tensorf: Tensorial radiance fields. In Computer Vision–ECCV 2022: 17th European Conference, Tel Aviv, Israel, October 23–27, 2022, Proceedings, Part XXXII, pages 333–350. Springer, 2022. 1, 3, 5, 7, 8, 9, 14, 21, 24
- [10] Anpei Chen, Zexiang Xu, Xinyue Wei, Siyu Tang, Hao Su, and Andreas Geiger. Factor fields: A unified framework for neural fields and beyond. arXiv preprint arXiv:2302.01226,

2023. 3, 7, 8, 16, 21

- [11] Changan Chen, Alexander Richard, Roman Shapovalov, Vamsi Krishna Ithapu, Natalia Neverova, Kristen Grauman, and Andrea Vedaldi. Novel-view acoustic synthesis. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 6409–6419, 2023. 1
- [12] Hao Chen, Bo He, Hanyu Wang, Yixuan Ren, Ser Nam Lim, and Abhinav Shrivastava. Nerv: Neural representations for videos. Advances in Neural Information Processing Systems, 34:21557–21568, 2021. 1
- [13] Yinbo Chen, Sifei Liu, and Xiaolong Wang. Learning continuous image representation with local implicit image function. In Proceedings of the IEEE/CVF conference on computer vision and pattern recognition, pages 8628–8638,

2021. 2

- [14] Zhang Chen, Anpei Chen, Guli Zhang, Chengyuan Wang, Yu Ji, Kiriakos N Kutulakos, and Jingyi Yu. A neural rendering

- framework for free-viewpoint relighting. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 5599–5610, 2020. 1
- [15] Zhiqin Chen and Hao Zhang. Learning implicit fields for generative shape modeling. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 5939–5948, 2019. 1, 2
- [16] Zhang Chen, Yinda Zhang, Kyle Genova, Sean Fanello, Sofien Bouaziz, Christian H¨ane, Ruofei Du, Cem Keskin, Thomas Funkhouser, and Danhang Tang. Multiresolution deep implicit functions for 3d shape representation. In Proceedings of the IEEE/CVF International Conference on Computer Vision, pages 13087–13096, 2021. 2, 3
- [17] Julian Chibane, Thiemo Alldieck, and Gerard Pons-Moll. Implicit functions in feature space for 3d shape reconstruction and completion. In Proceedings of the IEEE/CVF conference on computer vision and pattern recognition, pages 6970–6981, 2020. 2, 16
- [18] Shin-Fang Chng, Sameera Ramasinghe, Jamie Sherrah, and Simon Lucey. Gaussian activated neural radiance fields for high fidelity reconstruction and pose estimation. In Computer Vision–ECCV 2022: 17th European Conference, Tel Aviv, Israel, October 23–27, 2022, Proceedings, Part XXXIII, pages 264–280. Springer, 2022. 2
- [19] Junwoo Cho, Seungtae Nam, Daniel Rho, Jong Hwan Ko, and Eunbyung Park. Streamable neural fields. In Computer Vision–ECCV 2022: 17th European Conference, Tel Aviv, Israel, October 23–27, 2022, Proceedings, Part XX, pages 595–612. Springer, 2022. 2
- [20] Eastman Kodak Company. Kodak lossless true color image suite. https://r0k.us/graphics/kodak/. 6
- [21] Yueqi Duan, Haidong Zhu, He Wang, Li Yi, Ram Nevatia, and Leonidas J Guibas. Curriculum deepsdf. In Computer Vision–ECCV 2020: 16th European Conference, Glasgow, UK, August 23–28, 2020, Proceedings, Part VIII 16, pages 51–67. Springer, 2020. 2
- [22] Emilien Dupont, Hrushikesh Loya, Milad Alizadeh, Adam Golinski, Y Whye Teh, and Arnaud Doucet. Coin++: Neural compression across modalities. Transactions on Machine Learning Research, 2022(11), 2022. 1
- [23] Rizal Fathony, Anit Kumar Sahu, Devin Willmott, and J Zico Kolter. Multiplicative filter networks. In International Conference on Learning Representations, 2021. 2
- [24] Jie Feng, Ruimin Feng, Qing Wu, Zhiyong Zhang, Yuyao Zhang, and Hongjiang Wei. Spatiotemporal implicit neural representation for unsupervised dynamic mri reconstruction. arXiv preprint arXiv:2301.00127, 2022. 1
- [25] Sara Fridovich-Keil, Giacomo Meanti, Frederik Rahbæk Warburg, Benjamin Recht, and Angjoo Kanazawa. K-planes: Explicit radiance fields in space, time, and appearance. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 12479–12488, 2023. 1, 3, 5, 8, 9, 15, 21, 24
- [26] Sara Fridovich-Keil, Alex Yu, Matthew Tancik, Qinhong Chen, Benjamin Recht, and Angjoo Kanazawa. Plenoxels: Radiance fields without neural networks. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 5501–5510, 2022. 1, 2, 3, 8, 9, 21, 24

- [27] Kyle Genova, Forrester Cole, Avneesh Sud, Aaron Sarna, and Thomas Funkhouser. Local deep implicit functions for 3d shape. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 4857– 4866, 2020. 3
- [28] Kang Han and Wei Xiang. Multiscale tensor decomposition and rendering equation encoding for view synthesis. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 4232–4241, 2023. 2, 14
- [29] Zekun Hao, Arun Mallya, Serge Belongie, and Ming-Yu Liu. Implicit neural representations with levels-of-experts. In Advances in Neural Information Processing Systems, 2022. 2
- [30] Amir Hertz, Or Perel, Raja Giryes, Olga Sorkine-Hornung, and Daniel Cohen-Or. Sape: Spatially-adaptive progressive encoding for neural optimization. Advances in Neural Information Processing Systems, 34:8820–8832, 2021. 2
- [31] Langwen Huang and Torsten Hoefler. Compressing multidimensional weather and climate data into neural networks. arXiv preprint arXiv:2210.12538, 2022. 1
- [32] Chiyu Jiang, Avneesh Sud, Ameesh Makadia, Jingwei Huang, Matthias Nießner, Thomas Funkhouser, et al. Local implicit grid representations for 3d scenes. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 6001–6010, 2020. 1, 2
- [33] Animesh Karnewar, Tobias Ritschel, Oliver Wang, and Niloy Mitra. Relu fields: The little non-linearity that could. In ACM SIGGRAPH 2022 Conference Proceedings, pages 1–9,

2022. 2

- [34] Bernhard Kerbl, Georgios Kopanas, Thomas Leimk¨uhler, and George Drettakis. 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics (TOG), 42(4):1–14, 2023. 5
- [35] Diederik P Kingma and Jimmy Ba. Adam: A method for stochastic optimization. arXiv preprint arXiv:1412.6980,

2014. 5

- [36] Zoe Landgraf, Alexander Sorkine Hornung, and Ricardo Silveira Cabral. Pins: progressive implicit networks for multiscale neural representations. In Proceedings of the International Conference on Machine Learning (ICML), pages 11969–11984, 2022. 2
- [37] Marc Levoy, Kari Pulli, Brian Curless, Szymon Rusinkiewicz, David Koller, Lucas Pereira, Matt Ginzton, Sean Anderson, James Davis, Jeremy Ginsberg, et al. The digital michelangelo project: 3d scanning of large statues. In Proceedings of the 27th annual conference on Computer graphics and interactive techniques, pages 131–144, 2000. 7
- [38] Tianyang Li, Xin Wen, Yu-Shen Liu, Hua Su, and Zhizhong Han. Learning deep implicit functions for 3d shapes with dynamic code clouds. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 12840–12850, 2022. 3
- [39] Zhong Li, Liangchen Song, Celong Liu, Junsong Yuan, and Yi Xu. Neulf: Efficient novel view synthesis with neural 4d light field. In Eurographics Symposium on Rendering, 2022. 1

- [40] David B Lindell, Dave Van Veen, Jeong Joon Park, and Gordon Wetzstein. Bacon: Band-limited coordinate networks for multiscale scene representation. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 16252–16262, 2022. 2, 6, 17
- [41] Lingjie Liu, Jiatao Gu, Kyaw Zaw Lin, Tat-Seng Chua, and Christian Theobalt. Neural sparse voxel fields. Advances in Neural Information Processing Systems, 33:15651–15663,

- 2020. 1, 3

[42] Julien NP Martel, David B Lindell, Connor Z Lin, Eric R Chan, Marco Monteiro, and Gordon Wetzstein. Acorn: Adaptive coordinate networks for neural scene representation. ACM Transactions on Graphics (TOG), 40:1 – 13,

- 2021. 3

- [43] Ishit Mehta, Micha¨el Gharbi, Connelly Barnes, Eli Shechtman, Ravi Ramamoorthi, and Manmohan Chandraker. Modulated periodic activations for generalizable local functional representations. In Proceedings of the IEEE/CVF International Conference on Computer Vision, pages 14214–14223,

2021. 2

- [44] Lars Mescheder, Michael Oechsle, Michael Niemeyer, Sebastian Nowozin, and Andreas Geiger. Occupancy networks: Learning 3d reconstruction in function space. In Proceedings of the IEEE/CVF conference on computer vision and pattern recognition, pages 4460–4470, 2019. 1, 2
- [45] Mateusz Michalkiewicz, Jhony K Pontes, Dominic Jack, Mahsa Baktashmotlagh, and Anders Eriksson. Implicit surface representations as layers in neural networks. In Proceedings of the IEEE/CVF International Conference on Computer Vision, pages 4743–4752, 2019. 2
- [46] Ben Mildenhall, Pratul P Srinivasan, Rodrigo Ortiz-Cayon, Nima Khademi Kalantari, Ravi Ramamoorthi, Ren Ng, and Abhishek Kar. Local light field fusion: Practical view synthesis with prescriptive sampling guidelines. ACM Transactions on Graphics (TOG), 38(4):1–14, 2019. 8, 9, 15, 16, 17, 24, 25
- [47] Ben Mildenhall, Pratul P Srinivasan, Matthew Tancik, Jonathan T Barron, Ravi Ramamoorthi, and Ren Ng. Nerf: Representing scenes as neural radiance fields for view synthesis. Communications of the ACM, 65(1):99–106, 2021. 1, 2, 4, 7, 8, 9, 14, 16, 17, 21, 22, 23, 24
- [48] Thomas M¨uller, Alex Evans, Christoph Schied, and Alexander Keller. Instant neural graphics primitives with a multiresolution hash encoding. ACM Transactions on Graphics (ToG), 41(4):1–15, 2022. 1, 3, 5, 6, 7, 8, 9, 15, 16, 17, 19, 20, 21
- [49] Michael Oechsle, Songyou Peng, and Andreas Geiger. Unisurf: Unifying neural implicit surfaces and radiance fields for multi-view reconstruction. In Proceedings of the IEEE/CVF International Conference on Computer Vision, pages 5589–5599, 2021. 1
- [50] Jeong Joon Park, Peter Florence, Julian Straub, Richard Newcombe, and Steven Lovegrove. Deepsdf: Learning continuous signed distance functions for shape representation. In Proceedings of the IEEE/CVF conference on computer vision and pattern recognition, pages 165–174, 2019. 1, 2
- [51] Songyou Peng, Michael Niemeyer, Lars Mescheder, Marc Pollefeys, and Andreas Geiger. Convolutional occupancy

- networks. In Computer Vision–ECCV 2020: 16th European Conference, Glasgow, UK, August 23–28, 2020, Proceedings, Part III 16, pages 523–540. Springer, 2020. 1, 2, 3
- [52] Sameera Ramasinghe and Simon Lucey. Learning positional embeddings for coordinate-mlps. arXiv preprint arXiv:2112.11577, 2021. 2
- [53] Sameera Ramasinghe and Simon Lucey. Beyond periodicity: towards a unifying framework for activations in coordinatemlps. In Computer Vision–ECCV 2022: 17th European Conference, Tel Aviv, Israel, October 23–27, 2022, Proceedings, Part XXXIII, pages 142–158. Springer, 2022. 2
- [54] Christian Reiser, Songyou Peng, Yiyi Liao, and Andreas Geiger. Kilonerf: Speeding up neural radiance fields with thousands of tiny mlps. In Proceedings of the IEEE/CVF International Conference on Computer Vision, pages 14335– 14345, 2021. 2
- [55] Daniel Rho, Byeonghyeon Lee, Seungtae Nam, Joo Chan Lee, Jong Hwan Ko, and Eunbyung Park. Masked wavelet representation for compact neural radiance fields. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 20680–20690, 2023. 3
- [56] Radu Alexandru Rosu and Sven Behnke. Permutosdf: Fast multi-view reconstruction with implicit surfaces using permutohedral lattices. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 8466–8475, 2023. 3
- [57] Vishwanath Saragadam, Daniel LeJeune, Jasper Tan, Guha Balakrishnan, Ashok Veeraraghavan, and Richard G Baraniuk. Wire: Wavelet implicit neural representations. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 18507–18516, 2023. 2, 16
- [58] Vishwanath Saragadam, Jasper Tan, Guha Balakrishnan, Richard G Baraniuk, and Ashok Veeraraghavan. Miner: Multiscale implicit neural representation. In Computer Vision–ECCV 2022: 17th European Conference, Tel Aviv, Israel, October 23–27, 2022, Proceedings, Part XXIII, pages 318–333. Springer, 2022. 2, 3, 5, 6, 15
- [59] Friedhelm Schwenker, Hans A Kestler, and G¨unther Palm. Three learning phases for radial-basis-function networks. Neural networks, 14(4-5):439–458, 2001. 4
- [60] Shayan Shekarforoush, David Lindell, David J Fleet, and Marcus A Brubaker. Residual multiplicative filter networks for multiscale reconstruction. Advances in Neural Information Processing Systems, 35:8550–8563, 2022. 2
- [61] J Ryan Shue, Eric Ryan Chan, Ryan Po, Zachary Ankner, Jiajun Wu, and Gordon Wetzstein. 3d neural field generation using triplane diffusion. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 20875–20886, 2023. 3
- [62] Vincent Sitzmann, Julien Martel, Alexander Bergman, David Lindell, and Gordon Wetzstein. Implicit neural representations with periodic activation functions. Advances in Neural Information Processing Systems, 33:7462–7473, 2020. 1, 2, 4, 9
- [63] Liangchen Song, Anpei Chen, Zhong Li, Zhang Chen, Lele Chen, Junsong Yuan, Yi Xu, and Andreas Geiger. Nerfplayer: A streamable dynamic scene representation with de-

- composed neural radiance fields. IEEE Transactions on Visualization and Computer Graphics, 29(5):2732–2742, 2023. 1
- [64] Liangchen Song, Zhong Li, Xuan Gong, Lele Chen, Zhang Chen, Yi Xu, and Junsong Yuan. Harnessing low-frequency neural fields for few-shot view synthesis. arXiv preprint arXiv:2303.08370, 2023. 1
- [65] Stanford University. The Stanford 3d scanning repository. https://graphics.stanford.edu/data/ 3Dscanrep. 7
- [66] Yannick Str¨umpler, Janis Postels, Ren Yang, Luc Van Gool, and Federico Tombari. Implicit neural representations for image compression. In Computer Vision–ECCV 2022: 17th European Conference, Tel Aviv, Israel, October 23–27, 2022, Proceedings, Part XXVI, pages 74–91. Springer, 2022. 1
- [67] Cheng Sun, Min Sun, and Hwann-Tzong Chen. Direct voxel grid optimization: Super-fast convergence for radiance fields reconstruction. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 5459– 5469, 2022. 1, 2
- [68] Towaki Takikawa, Alex Evans, Jonathan Tremblay, Thomas M¨uller, Morgan McGuire, Alec Jacobson, and Sanja Fidler. Variable bitrate neural fields. In ACM SIGGRAPH 2022 Conference Proceedings, pages 1–9, 2022. 3
- [69] Towaki Takikawa, Joey Litalien, Kangxue Yin, Karsten Kreis, Charles Loop, Derek Nowrouzezahrai, Alec Jacobson, Morgan McGuire, and Sanja Fidler. Neural geometric level of detail: Real-time rendering with implicit 3d shapes. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 11358–11367, 2021. 2, 7, 17, 19, 20
- [70] Matthew Tancik, Pratul Srinivasan, Ben Mildenhall, Sara Fridovich-Keil, Nithin Raghavan, Utkarsh Singhal, Ravi Ramamoorthi, Jonathan Barron, and Ren Ng. Fourier features let networks learn high frequency functions in low dimensional domains. Advances in Neural Information Processing Systems, 33:7537–7547, 2020. 1, 2, 4
- [71] Radu Timofte, Eirikur Agustsson, Luc Van Gool, MingHsuan Yang, Lei Zhang, Bee Lim, et al. Ntire 2017 challenge on single image super-resolution: Methods and results. In The IEEE Conference on Computer Vision and Pattern Recognition (CVPR) Workshops, July 2017. 5, 6, 9, 14, 15
- [72] Peng-Shuai Wang, Yang Liu, Yu-Qi Yang, and Xin Tong. Spline positional encoding for learning 3d implicit signed distance fields. 2021. 2
- [73] Francis Williams, Zan Gojcic, Sameh Khamis, Denis Zorin, Joan Bruna, Sanja Fidler, and Or Litany. Neural fields as learnable kernels for 3d reconstruction. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 18500–18510, 2022. 2
- [74] Francis Williams, Matthew Trager, Joan Bruna, and Denis Zorin. Neural splines: Fitting 3d surfaces with infinitelywide neural networks. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 9949–9958, 2021. 2
- [75] Jelmer M Wolterink, Jesse C Zwienenberg, and Christoph Brune. Implicit neural representations for deformable image

- registration. In International Conference on Medical Imaging with Deep Learning, pages 1349–1359. PMLR, 2022. 1
- [76] Zhijie Wu, Yuhe Jin, and Kwang Moo Yi. Neural fourier filter bank. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 14153– 14163, 2023. 3
- [77] Qiangeng Xu, Weiyue Wang, Duygu Ceylan, Radomir Mech, and Ulrich Neumann. Disn: Deep implicit surface network for high-quality single-view 3d reconstruction. Advances in neural information processing systems, 32, 2019. 2
- [78] Qiangeng Xu, Zexiang Xu, Julien Philip, Sai Bi, Zhixin Shu, Kalyan Sunkavalli, and Ulrich Neumann. Point-nerf: Point-based neural radiance fields. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 5438–5448, 2022. 3, 5, 7, 8, 21
- [79] Xiangyu Xu, Lichang Chen, Changjiang Cai, Huangying Zhan, Qingan Yan, Pan Ji, Junsong Yuan, Heng Huang, and Yi Xu. Dynamic voxel grid optimization for high-fidelity rgb-d supervised surface reconstruction. arXiv preprint arXiv:2304.06178, 2023. 1
- [80] Guandao Yang, Sagie Benaim, Varun Jampani, Kyle Genova, Jonathan Barron, Thomas Funkhouser, Bharath Hariharan, and Serge Belongie. Polynomial neural fields for subband decomposition and manipulation. Advances in Neural Information Processing Systems, 35:4401–4415, 2022. 2, 6
- [81] Runzhao Yang, Tingxiong Xiao, Yuxiao Cheng, Qianni Cao, Jinyuan Qu, Jinli Suo, and Qionghai Dai. Sci: A spectrum concentrated implicit neural compression for biomedical data. In Proceedings of the AAAI Conference on Artificial Intelligence, volume 37, pages 4774–4782, 2023. 1
- [82] Runzhao Yang, Tingxiong Xiao, Yuxiao Cheng, Jinli Suo, and Qionghai Dai. Tinc: Tree-structured implicit neural compression. pages 18517–18526, 2023. 3
- [83] Lior Yariv, Jiatao Gu, Yoni Kasten, and Yaron Lipman. Volume rendering of neural implicit surfaces. Advances in Neural Information Processing Systems, 34:4805–4815, 2021. 1
- [84] Alex Yu, Ruilong Li, Matthew Tancik, Hao Li, Ren Ng, and Angjoo Kanazawa. Plenoctrees for real-time rendering of neural radiance fields. In Proceedings of the IEEE/CVF International Conference on Computer Vision, pages 5752– 5761, 2021. 2, 3
- [85] Gizem Y¨uce, Guillermo Ortiz-Jim´enez, Beril Besbinar, and Pascal Frossard. A structured dictionary perspective on implicit neural representations. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 19228–19238, 2022. 2
- [86] Yunfan Zhang, Ties van Rozendaal, Johann Brehmer, Markus Nagel, and Taco Cohen. Implicit neural video compression. arXiv preprint arXiv:2112.11312, 2021. 1
- [87] Jianqiao Zheng, Sameera Ramasinghe, and Simon Lucey. Rethinking positional encoding. arXiv preprint arXiv:2107.02561, 2021. 2

### A. Illustration of the Discontinuity in Adaptive RBFs

As shown in Fig. 11, consider a simple 1D case where x1 ≈ x2 are two points located on the boundary where U(x) changes. Let U(x1) = {1}, U(x2) = {2} be the sets of their closest RBF. From Eq. (2) in the paper, the aggregated neural feature gb(x) is computed as gb(x) =

i∈U(x) φ(x,ci,Σi)wi. Generally, for adaptive RBFs, φ(x1,c1,Σ1) ̸≈ φ(x2,c2,Σ2) and w1 ̸≈ w2. Therefore, gb(x1) ̸≈ gb(x2). This reveals a discontinuity in gb(x) when x changes from x1 to x2. On the other hand, for gridbased RBFs that use linear interpolation as kernel function, both φ(x1,c1) and φ(x2,c2) are close to 0, so gb(x) does not contain such discontinuity. We combine adaptive and grid-based RBFs through feature concatenation to balance fitting accuracy and interpolation smoothness.

### B. Details on RBF Initialization

We utilize the EM-style Lloyd’s K-Means algorithm to initialize RBF positions using all points. The number of RBFs is calculated based on parameter budget. The initialization is conducted only once per scene, before the start of training. We do not split or merge RBFs during training. During weighted K-Means, the initial centers are generated by weighted random sampling. We do not repeat this random sampling for multiple times because we observe it does not have major influence on final performance. The E-M steps are the following:

 

1,if i = arg min

∥xj − ck∥2, 0,otherwise.

(10)

aij =

k



aijwjxj j aijwj

ci = j

. (11)

aij is an indicator variable: aij = 1 if xj is assigned to cluster i and aij = 0 otherwise. For efficiency, we iterate Eq. (10)(11) for only 10 steps as the results are already close to convergence and sufficient for our use case. We implement the E-M steps with parallel KD Tree and vectorized centroid update.

### C. More Ablation Study C.1. RBF Initialization

To evaluate the effects of RBF initialization, we compare weighted K-Means with grid initialization, random initialization and weighted random initialization. As shown in Fig. 12, we use an image from DIV2K dataset [3, 71] and conduct 2D image fitting. To facilitate visualization, we only use 15129 RBFs in each baseline. We visualize the position and shape parameters of RBFs as yellow ellipses, and

Grid-Based RBFs Adaptive RBFs

[Figure 118]

[Figure 119]

[Figure 120]

[Figure 121]

[Figure 122]

[Figure 123]

[Figure 124]

[Figure 125]

[Figure 126]

[Figure 127]

| |
|---|
| |
| |

| |
|---|
| |
| |

[Figure 128]

[Figure 129]

[Figure 130]

[Figure 131]

Figure 11. Illustration of the discontinuity in adaptive RBFs.

show the fitting error maps and PSNR. As demonstrated in the top two rows, weighted K-Means initialization achieves the highest fitting accuracy. Among the other three baselines, weighted random initialization has a competitve performance while random initialization leads to the worst result.

In the bottom four rows, we further evaluate the effectiveness of using gradient backpropagation to finetune RBF parameters during training. We first use a set of reasonable learning rates for position and shape parameters, which are obtained through grid search on the baseline with weighted random initialization. As shown in the middle two rows, gradient backpropagation (with only L2 loss on pixel value) only provides minor improvement compared to the first two rows. Besides, the update to the RBF parameters is barely noticeable for grid initialization. Then, we experiment with large learning rates in the last two rows. It can be seen that the RBF parameters can be largely changed from their initialization. However, this leads to significant performance drop for all baselines. The above results validate the benefits of RBF initialization.

#### C.2. Adaptive Positions and Generalized Interpolation

Here, we evaluate the effects of using adaptive positions for RBFs and generalizing N-dimensional linear interpolation to RBFs with shape parameters. We conduct this ablation study on image, SDF and NeRF tasks, and the results are shown in Fig. 13. The parameter count of each model is 567K, 856K and 17.7M respectively for the three tasks. Based on the results, both adaptive positions and generalized interpolation are beneficial to performance.

### D. More Implementation Details

Architecture. For the decoder network gm, except NeRF task, we use a 3-layer MLP (2 hidden layers + 1 output layer) with a network width of 64 neurons, where rectified linear unit (ReLU) activation function is applied to the second hidden layer. The MLP uses a very small part of the parameters (e.g., only 7K in image fitting). For the NeRF experiments on the Synthetic NeRF dataset [47], we use a single Softplus layer as density decoder (same as TensoRF [9]) and use the rendering equation encoding from NRFF [28] as

Grid Init. Random Init. Weighted Random Init. Weighted K-Means Init.

[Figure 132]

[Figure 133]

[Figure 134]

[Figure 135]

NoFinetuning Grid-Searched

0.05

[Figure 136]

[Figure 137]

[Figure 138]

[Figure 139]

[Figure 140]

0

PSNR↑ : 32.73 dB 31.61 dB 34.17 dB 35.24 dB

[Figure 141]

[Figure 142]

[Figure 143]

[Figure 144]

LearningRates Large

[Figure 145]

[Figure 146]

[Figure 147]

[Figure 148]

32.56 dB 31.57 dB 34.79 dB 35.71 dB

[Figure 149]

[Figure 150]

[Figure 151]

[Figure 152]

LearningRates

[Figure 153]

[Figure 154]

[Figure 155]

[Figure 156]

22.93 dB 22.80 dB 23.40 dB 23.56 dB

- Figure 12. Evaluation on RBF Initialization. We compare different RBF initialization methods in columns: grid initialization, random initialization, weighted random initialization and weighted K-Means initialization. We also evaluate different RBF finetuning strategies using gradient backpropagation (with only L2 loss on pixel value) in rows: no finetuning, grid-searched learning rates, large learning rates. For each result, we visualize the RBF parameters as yellow ellipses and show fitting error maps.

color decoder. For the NeRF experiments on the real LLFF Forward-Facing dataset [46], we adopt the same network architecture as K-Planes-hybrid [25], which uses a 2-layer MLP for density decoder and a 3-layer MLP for color decoder.

periments. Note that some results in their paper use smaller hash table sizes, hence fewer parameters but also lower PSNR. For MINER [58], we use the implementation from MINER pl1. The original MINER paper does not report their results on the DIV2K dataset [3, 71]. All methods use a batch size of 262144 and are trained for a same number of steps.

##### Experiments on 2D Image Fitting. The neural features

wi of adaptive RBFs have a channel dimension of 32. The neighboring RBFs U(x) of a point x is its 4 nearest neighbors. For Instant NGP [48], we use their official opensourced codes and hyper-parameters in the comparison ex-

1https://github.com/kwea123/MINER_pl

GT Full No Adaptive Positions No Generalized Interp.

|[Figure 157]|
|---|

|[Figure 158]|
|---|

|[Figure 159]|
|---|

|[Figure 160]|
|---|

[Figure 161]

[Figure 162]

[Figure 163]

[Figure 164]

Image

2040 × 1356 × 3

PSNR↑ : 34.35 dB 31.97 dB 33.14 dB

[Figure 165]

[Figure 166]

[Figure 167]

[Figure 168]

|[Figure 169]|
|---|

|[Figure 170]|
|---|

|[Figure 171]|
|---|

|[Figure 172]|
|---|

SDF

NAE↓ : 5.30° 6.81° 6.48°

[Figure 173]

[Figure 174]

[Figure 175]

[Figure 176]

|[Figure 177]|
|---|

|[Figure 178]|
|---|

|[Figure 179]|
|---|

|[Figure 180]|
|---|

NeRF

PSNR↑ : 37.56 dB 37.42 dB 37.44 dB

- Figure 13. Evaluation on the adaptive positions and generalized interpolation of RBFs. “No Adaptive Positions”: the positions of RBFs are fixed to a grid structure. “No Generalized Interp.”: the interpolation function is N-dimensional linear interpolation.

##### Experiments on 3D SDF Reconstruction. The neural

the channel dimension of adaptive RBFs is 16 and the size of neighborhood U(x) is 8. The grid-based model used for distillation is trained for 2000 steps while the full model is trained for 38000 steps.

features wi of adaptive RBFs have a channel dimension of 16, and the size of neighborhood U(x) is 8. We use a grid resolution of 10243 for marching cubes. IoU is evaluated on these grid points. For normal angular error (NAE), it is computed similarly as normal consistency [17], but is in unit of degree. Specifically, let P1,P2 be randomly sampled points on two mesh surfaces, NN(x,P) be the closest point to x in point set P, and nf(x) ∈ R3×1 be the unit face normal of point x, NAE is calculated as:

### E. Limitations and Future Work

In this work, we have primarily focused on local neural representation. It could be promising to explore the combination with other activation functions in MLP (e.g., WIRE [57]). Besides, in our current implementation, the multipliers m,m0 are treated as hyper-parameters and are not trainable. We tried training them along with other parameters, but observed little improvement. A possible reason is that they act as frequencies and would require tailored optimization techniques.

- 1

- 2 ·

180

NAE(P1,P2) =

π · ( 1

(12)

- |P1| p

1∈P1

arccos nf(p1)Tnf(NN(p1,P2)) + 1

- |P2| p

arccos nf(p2)Tnf(NN(p2,P1)) ).

Our method demonstrates high representation accuracy in spatial domains; however, similar to Instant NGP [48] and Factor Fields [10], we have not explored spatialtemporal tasks such as dynamic novel view synthesis. By extending radial basis functions into higher dimensions or using dimension decomposition techniques, our method can potentially be applied to these tasks. We also observe that it is difficult to represent large-scale complicated signals with both high accuracy and small model size, which is a com-

2∈P2

Experiments on Neural Radiance Field Reconstruction. For the Synthetic NeRF dataset [47], the channel dimension of adaptive RBFs is 32 and the size of neighborhood U(x) is 5. We first train the grid-based part for 1000 steps, which is then used to distill scene information and conduct RBF initialization. For the real LLFF Forward-Facing dataset [46],

Avg. Armadillo Bunny Dragon Buddha Lucy XYZ Dragon Statuette David Chameleon Mechanism NAE↓

NGLOD5 [69] 6.58 3.60 4.81 2.85 3.28 4.73 5.66 7.53 3.43 15.91 14.00 NGLOD6 [69] 6.14 3.35 4.47 2.76 3.02 4.28 5.15 6.46 3.22 14.64 14.03 I-NGP [48] 5.70 2.89 1.96 2.30 2.73 3.57 4.51 6.00 2.88 11.96 18.21 Ours 4.93 2.83 2.00 2.22 2.69 3.36 4.14 5.30 2.62 10.42 13.73

I-NGP400K [48] 6.39 3.20 2.22 2.64 3.18 4.29 4.96 6.82 3.27 13.04 20.31 Ours400K 5.53 2.89 2.14 2.35 2.88 3.70 4.44 6.07 2.85 11.96 16.00

###### IoU↑

NGLOD5 [69] 0.9962 0.99974 0.97664 0.99964 0.99977 0.99979 0.99981 0.99969 0.99960 0.99456 0.99237 NGLOD6 [69] 0.9963 0.99979 0.97696 0.99969 0.99977 0.99986 0.99983 0.99980 0.99963 0.99528 0.99237 I-NGP [48] 0.9994 0.99997 0.99968 0.99995 0.99996 0.99997 0.99996 0.99993 0.99993 0.99893 0.99605 Ours 0.9995 0.99994 0.99943 0.99995 0.99996 0.99996 0.99996 0.99995 0.99993 0.99765 0.99837

I-NGP400K [48] 0.9992 0.99995 0.99974 0.99994 0.99994 0.99996 0.99995 0.99990 0.99990 0.99820 0.99448 Ours400K 0.9994 0.99996 0.99964 0.99995 0.99995 0.99997 0.99995 0.99991 0.99992 0.99706 0.99767

- Table 6. 3D Signed Distance Field Reconstruction. Per-object breakdown of the quantitative metrics (NAE↓ and IoU↑) in Table 2 of the paper.

mon challenge for local neural fields methods. An interesting future direction would be to design basis functions with more adaptive shapes and long-range support.

### F. Additional Results

#### F.1. 2D Image Fitting

- Fig. 14 compares the results on 4 ultra-high resolution

images that are not displayed in the paper due to page limit. For the error maps, we calculate the mean absolute error across color channels for each pixel. To highlight the difference among methods, we set the color bar range as 0 ∼ 0.01 (the range of pixel value is 0 ∼ 1).

For the Pluto image (Fig. 4 row 2 in the paper), when fitting the 16 megapixel version of it, our method can reach 44.13 dB PSNR with 7.8M parameters and 50s training.

F.2. 3D SDF Reconstruction

Table 6 shows per-object breakdown of the quantitative metrics (NAE↓ and IoU↑) in Table 2 of the paper.

- Fig. 15, 16 show the qualitative results, where the numbers of trainable parameters for Instant NGP and ours are 950K and 856K.

We further compare with BACON [40] and let our method use the same training settings as them. BACON uses 531K parameters while our models only use 448K. Averaging over 4 scenes (Armadillo, Lucy, XYZ Dragon, Statuette), the normal angular errors (NAE↓) are 5.89◦(BACON) vs. 4.53◦(Ours).

#### F.3. Neural Radiance Field Reconstruction

Table 7 and 8 demonstrate the per-scene quantitative comparisons (PSNR↑, SSIM↑, LPIPSV GG↓, LPIPSAlex↓) on the Synthetic NeRF dataset [47] and the real LLFF

Forward-Facing dataset [46]. Fig. 17 and Fig. 18 show more close-up and full-image comparisons on the Synthetic NeRF dataset [47]. Fig. 19 shows full-image comparisons on the real LLFF Forward-Facing dataset [46].

MINER Instant NGP Ours

0.01

[Figure 181]

[Figure 182]

[Figure 183]

[Figure 184]

[Figure 185]

###### # Tr. Params↓ : 45.18M | PSNR↑ : 49.91 dB 0 SSIM↑ : 0.997 | LPIPSAlex↓ : 6.55×10-4

6000 × 4000 × 3

35.85M | 50.02 dB 0.997 | 8.07×10-4

33.43M | 56.86 dB 0.999 | 2.20×10-4

[Figure 186]

[Figure 187]

[Figure 188]

[Figure 189]

8000 × 9302 × 3

90.89M | 39.12 dB 0.982 | 1.61×10-2

71.86M | 39.59 dB 0.980 | 1.46×10-2

67.00M | 44.19 dB 0.988 | 1.22×10-2

[Figure 190]

[Figure 191]

Ours

137.38M | 44.08 dB 0.989 | 1.73×10-2

29164 × 8592 × 3

[Figure 192]

[Figure 193]

InstantNGP

MINER

147.34M | 40.87 dB 0.982 | 3.09×10-2

188.43M | 39.91 dB 0.985 | 2.43×10-2

[Figure 194]

[Figure 195]

InstantNGPOurs

56718 × 21450 × 3

178.06M | 38.59 dB 0.926

[Figure 196]

[Figure 197]

MINER

196.22M | 37.64 dB 0.918

181.42M | 37.74 dB 0.915

- Figure 14. 2D Image Fitting. Leftmost column or top left quarter shows the fitted images of our method and the resolution of the images. The other columns or quarters show the error maps of each method, along with the number of trainable parameters (“# Tr. Params”)↓,

PSNR↑, SSIM↑ and LPIPSAlex↓. For the last image, its resolution is too high to compute LPIPSAlex. “Girl With a Pearl Earring” renovation ©Koorosh Orooj (CC BY-SA 4.0).

NGLOD6 Instant NGP Ours GT

[Figure 198]

[Figure 199]

[Figure 200]

[Figure 201]

Armadillo

[Figure 202]

[Figure 203]

[Figure 204]

[Figure 205]

Bunny

[Figure 206]

[Figure 207]

[Figure 208]

[Figure 209]

Dragon

[Figure 210]

[Figure 211]

[Figure 212]

[Figure 213]

Buddha

[Figure 214]

[Figure 215]

[Figure 216]

[Figure 217]

Lucy

- Figure 15. 3D SDF Reconstruction. Qualitative comparisons between NGLOD6 [69], Instant NGP [48] and ours. For the results in this figure, the number of trainable parameters of Instant NGP is 950K, while that of ours is 856K. (To be continued in the next page.)

[Figure 218]

[Figure 219]

[Figure 220]

[Figure 221]

NGLOD6 Instant NGP Ours GT

XYZ Dragon

[Figure 222]

[Figure 223]

[Figure 224]

[Figure 225]

Statuette

[Figure 226]

[Figure 227]

[Figure 228]

[Figure 229]

David

[Figure 230]

[Figure 231]

[Figure 232]

[Figure 233]

Chameleon

[Figure 234]

[Figure 235]

[Figure 236]

[Figure 237]

Mechanism

- Figure 16. 3D SDF Reconstruction. Qualitative comparisons between NGLOD6 [69], Instant NGP [48] and ours. For the results in this figure, the number of trainable parameters of Instant NGP is 950K, while that of ours is 856K.

Methods Avg. Chair Drums Ficus Hotdog Lego Materials Mic Ship PSNR↑ NeRF [47] 31.01 33.00 25.01 30.13 36.18 32.54 29.62 32.91 28.65 Mip-NeRF 360 [4] 33.25 - - - - - - - Point-NeRF [78] 33.31 35.40 26.06 36.13 37.30 35.04 29.61 35.95 30.97 Plenoxels [26] 31.71 33.98 25.35 31.83 36.43 34.10 29.14 33.26 29.62 Instant NGP [48] 33.18 35.00 26.02 33.51 37.40 36.39 29.78 36.22 31.10 TensoRF [9] 33.14 35.76 26.01 33.99 37.41 36.46 30.12 34.61 30.77 Factor Fields [10] 33.14 - - - - - - - K-Planes [25] 32.36 34.99 25.66 31.41 36.78 35.75 29.48 34.05 30.74 Ours 34.62 36.74 26.47 35.14 38.65 37.53 34.30 36.17 31.94 Ours3.66M 33.97 35.82 26.19 34.08 38.11 36.75 34.32 35.49 31.03 SSIM↑ NeRF [47] 0.947 0.967 0.925 0.964 0.974 0.961 0.949 0.980 0.856 Mip-NeRF 360 [4] 0.962 - - - - - - - Point-NeRF [78] 0.962 0.984 0.935 0.987 0.982 0.978 0.948 0.990 0.892 Plenoxels [26] 0.958 0.977 0.933 0.976 0.980 0.976 0.949 0.985 0.890 Instant NGP [48] 0.963 0.985 0.940 0.982 0.982 0.982 0.949 0.989 0.893 TensoRF [9] 0.963 0.985 0.937 0.982 0.982 0.983 0.952 0.988 0.895 Factor Fields [10] 0.961 - - - - - - - K-Planes [25] 0.962 0.983 0.938 0.975 0.982 0.982 0.950 0.988 0.897 Ours 0.975 0.988 0.946 0.987 0.987 0.986 0.980 0.992 0.930 Ours3.66M 0.971 0.985 0.942 0.984 0.985 0.984 0.980 0.990 0.919 LPIPSV GG↓ NeRF [47] 0.081 0.046 0.091 0.044 0.121 0.050 0.063 0.028 0.206 Mip-NeRF 360 [4] 0.039 - - - - - - - Point-NeRF [78] 0.050 0.023 0.078 0.022 0.037 0.024 0.072 0.014 0.124 Plenoxels [26] 0.049 0.031 0.067 0.026 0.037 0.028 0.057 0.015 0.134 Instant NGP [48] 0.051 0.023 0.076 0.027 0.038 0.021 0.065 0.020 0.137 TensoRF [9] 0.047 0.022 0.073 0.022 0.032 0.018 0.058 0.015 0.138 Factor Fields [10] - - - - - - - - K-Planes [25] 0.062 0.027 0.089 0.056 0.034 0.047 0.068 0.029 0.148 Ours 0.034 0.015 0.059 0.014 0.021 0.015 0.031 0.008 0.110 Ours3.66M 0.039 0.019 0.065 0.019 0.025 0.018 0.034 0.010 0.124 LPIPSAlex↓ Point-NeRF [78] 0.028 0.010 0.055 0.009 0.016 0.011 0.041 0.007 0.070 Instant NGP [48] 0.028 0.0097 0.0540 0.0174 0.0142 0.0085 0.0296 0.0072 0.0863 TensoRF [9] 0.027 0.010 0.051 0.012 0.013 0.007 0.026 0.009 0.085 K-Planes [25] 0.031 0.0125 0.0527 0.0209 0.0170 0.0096 0.0303 0.0091 0.0968 Ours 0.018 0.0067 0.0409 0.0085 0.0085 0.0057 0.0106 0.0044 0.0614 Ours3.66M 0.022 0.0088 0.0454 0.0101 0.0109 0.0070 0.0119 0.0060 0.0735

- Table 7. Neural Radiance Field Reconstruction. Per-scene quantitative comparisons (PSNR↑, SSIM↑, LPIPSV GG↓, LPIPSAlex↓) on the Synthetic NeRF dataset [47]. Best 3 scores in each scene are marked with gold , silver and bronze . “-” denotes scores that are

unavailable in prior work. For LPIPSAlex, since the scores of NeRF [47], Mip-NeRF 360 [4], Plenoxels [26] and Factor Fields [10] are unavailable in prior work, we exclude these methods in this metric.

|[Figure 238]|
|---|

|[Figure 239]|
|---|

|[Figure 240]|
|---|

|[Figure 241]|
|---|

|[Figure 242]|
|---|

|[Figure 243]|
|---|

[Figure 244]

| |
|---|

[Figure 245]

|[Figure 246]|
|---|

|[Figure 247]|
|---|

|[Figure 248]|
|---|

|[Figure 249]|
|---|

|[Figure 250]|
|---|

|[Figure 251]|
|---|

| |
|---|

[Figure 252]

|[Figure 253]|
|---|

|[Figure 254]|
|---|

|[Figure 255]|
|---|

|[Figure 256]|
|---|

|[Figure 257]|
|---|

|[Figure 258]|
|---|

| |
|---|

[Figure 259]

|[Figure 260]|
|---|

|[Figure 261]|
|---|

|[Figure 262]|
|---|

|[Figure 263]|
|---|

|[Figure 264]|
|---|

|[Figure 265]|
|---|

| |
|---|

[Figure 266]

|[Figure 267]|
|---|

|[Figure 268]|
|---|

|[Figure 269]|
|---|

|[Figure 270]|
|---|

|[Figure 271]|
|---|

|[Figure 272]|
|---|

| |
|---|

Point-NeRF Instant NGP TensoRF K-Planes Ours Ground Truth

- Figure 17. Neural Radiance Field Reconstruction. More close-up comparisons on the Synthetic NeRF Dataset [47]. Leftmost column shows the full-image results of our method.

[Figure 273]

[Figure 274]

[Figure 275]

[Figure 276]

[Figure 277]

[Figure 278]

[Figure 279]

[Figure 280]

[Figure 281]

[Figure 282]

[Figure 283]

[Figure 284]

[Figure 285]

[Figure 286]

[Figure 287]

[Figure 288]

[Figure 289]

[Figure 290]

[Figure 291]

[Figure 292]

[Figure 293]

[Figure 294]

[Figure 295]

[Figure 296]

[Figure 297]

[Figure 298]

[Figure 299]

[Figure 300]

[Figure 301]

[Figure 302]

[Figure 303]

[Figure 304]

[Figure 305]

[Figure 306]

[Figure 307]

[Figure 308]

[Figure 309]

[Figure 310]

[Figure 311]

[Figure 312]

[Figure 313]

[Figure 314]

[Figure 315]

[Figure 316]

[Figure 317]

[Figure 318]

[Figure 319]

[Figure 320]

Point-NeRF Instant NGP TensoRF K-Planes Ours Ground Truth

Figure 18. Neural Radiance Field Reconstruction. Full-image comparisons on the Synthetic NeRF Dataset [47].

Methods Avg. Room Fern Leaves Fortress Orchids Flower T-Rex Horns PSNR↑

NeRF [47] 26.50 32.70 25.17 20.92 31.16 20.36 27.40 26.80 27.45 Mip-NeRF 360 [4] 26.86 - - - - - - - Plenoxels [26] 26.29 30.22 25.46 21.41 31.09 20.24 27.83 26.48 27.58 TensoRF [9] 26.73 32.35 25.27 21.30 31.36 19.87 28.60 26.97 28.14 K-Planes [25] 26.92 32.64 25.38 21.30 30.44 20.26 28.67 28.01 28.64

Ours 27.05 32.80 25.48 21.81 30.98 20.03 28.57 28.06 28.68 SSIM↑

NeRF [47] 0.811 0.948 0.792 0.690 0.881 0.641 0.827 0.880 0.828 Mip-NeRF 360 [4] 0.858 - - - - - - - Plenoxels [26] 0.839 0.937 0.832 0.760 0.885 0.687 0.862 0.890 0.857 TensoRF [9] 0.839 0.952 0.814 0.752 0.897 0.649 0.871 0.900 0.877 K-Planes [25] 0.847 0.957 0.828 0.746 0.890 0.676 0.872 0.915 0.892

Ours 0.849 0.955 0.822 0.769 0.891 0.675 0.868 0.916 0.895 LPIPSV GG↓

NeRF [47] 0.250 0.178 0.280 0.316 0.171 0.321 0.219 0.249 0.268 Plenoxels [26] 0.210 0.192 0.224 0.198 0.180 0.242 0.179 0.238 0.231 TensoRF [9] 0.204 0.167 0.237 0.217 0.148 0.278 0.169 0.221 0.196 K-Planes [25] 0.194 0.147 0.223 0.242 0.154 0.250 0.165 0.199 0.173

Ours 0.179 0.134 0.209 0.238 0.128 0.271 0.147 0.158 0.149 LPIPSAlex↓

TensoRF [9] 0.124 0.082 0.155 0.153 0.075 0.201 0.106 0.099 0.123 K-Planes [25] 0.102 0.066 0.130 0.153 0.068 0.151 0.088 0.071 0.092

Ours 0.090 0.059 0.111 0.127 0.056 0.160 0.072 0.057 0.075

- Table 8. Neural Radiance Field Reconstruction. Per-scene quantitative comparisons (PSNR↑, SSIM↑, LPIPSV GG↓, LPIPSAlex↓) on the real LLFF Forward-Facing dataset [46]. Best 3 scores in each scene are marked with gold , silver and bronze . “-” denotes scores

that are unavailable in prior work. For LPIPSAlex, since the scores of NeRF [47], Mip-NeRF 360 [4] and Plenoxels [26] are unavailable in prior work, we exclude these methods in this metric.

[Figure 321]

[Figure 322]

[Figure 323]

[Figure 324]

[Figure 325]

[Figure 326]

[Figure 327]

[Figure 328]

[Figure 329]

[Figure 330]

[Figure 331]

[Figure 332]

[Figure 333]

[Figure 334]

[Figure 335]

[Figure 336]

[Figure 337]

[Figure 338]

[Figure 339]

[Figure 340]

[Figure 341]

[Figure 342]

[Figure 343]

[Figure 344]

[Figure 345]

[Figure 346]

[Figure 347]

[Figure 348]

[Figure 349]

[Figure 350]

[Figure 351]

[Figure 352]

TensoRF K-Planes Ours Ground Truth

Figure 19. Neural Radiance Field Reconstruction. Full-image comparisons on the real LLFF Forward-Facing dataset [46].

