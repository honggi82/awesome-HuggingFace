## GES : Generalized Exponential Splatting for Efficient Radiance Field Rendering

# arXiv:2402.10128v2[cs.CV]24May2024

Abdullah Hamdi1 Luke Melas-Kyriazi1 Jinjie Mai2 Guocheng Qian2,4 Ruoshi Liu3 Carl Vondrick3 Bernard Ghanem2 Andrea Vedaldi1 1Visual Geometry Group, University of Oxford 2King Abdullah University of Science and Technology (KAUST) 3Columbia University 4Snap Inc.

abdullah.hamdi@eng.ox.ac.uk

[Figure 1]

#### Abstract

PSNR Memory

Speed

[Figure 2]

[Figure 3]

Advancements in 3D Gaussian Splatting have significantly accelerated 3D reconstruction and generation. However, it may require a large number of Gaussians, which creates a substantial memory footprint. This paper introduces GES (Generalized Exponential Splatting), a novel representation that employs Generalized Exponential Function (GEF) to model 3D scenes, requiring far fewer particles to represent a scene and thus significantly outperforming Gaussian Splatting methods in efficiency with a plugand-play replacement ability for Gaussian-based utilities. GES is validated theoretically and empirically in both principled 1D setup and realistic 3D scenes. It is shown to represent signals with sharp edges more accurately, which are typically challenging for Gaussians due to their inherent low-pass characteristics. Our empirical analysis demonstrates that GEF outperforms Gaussians in fitting naturaloccurring signals (e.g. squares, triangles, parabolic signals), thereby reducing the need for extensive splitting operations that increase the memory footprint of Gaussian Splatting. With the aid of a frequency-modulated loss, GES achieves competitive performance in novel-view synthesis benchmarks while requiring less than half the memory storage of Gaussian Splatting and increasing the rendering speed by up to 39%. The code is available on the project website https://abdullahamdi.com/ges.

[Figure 4]

[Figure 5]

Gaussian Splatting

676MB

[Figure 6]

[Figure 7]

29.41db

[Figure 8]

[Figure 9]

###### 137 FPS

[Figure 10]

[Figure 11]

[Figure 12]

[Figure 13]

[Figure 14]

GES

399MB

[Figure 15]

[Figure 16]

[Figure 17]

[Figure 18]

###### 29.68db 160 FPS

Figure 1. GES: Generalized Exponential Splatting We propose a faster and more memory-efficient alternative to Gaussian Splatting [27] that relies on Generalized exponential Functions (with additional learnable shape parameters) instead of Gaussians.

mixture of small, coloured Gaussians. Its key advantage is the existence of a very fast differentiable renderer, which makes this representation ideally suited for real-time applications and significantly reduces the learning cost. Specifically, fast rendering of learnable 3D representations is of key importance for applications like gaming, where highquality, fluid, and responsive graphics are essential.

However, GS is not without shortcomings. We notice in particular that GS implicitly makes an assumption on the nature of the modeled signals, which is suboptimal. Specifically, Gaussians correspond to low-pass filters, but most 3D scenes are far from low-pass as they contain abrupt discontinuities in shape and appearance. Fig.2 demosntrates this inherent low-pass limitation of Gaussian-based methods. As a result, GS needs to use a huge number of very small Gaussians to represent such 3D scenes, far more than if a more appropriate basis was selected, which negatively impacts memory utilization.

#### 1. Introduction

The pursuit of more engaging and immersive virtual experiences across gaming, cinema, and the metaverse demands advancements in 3D technologies that balance visual richness with computational efficiency. In this regard, 3D Gaussian Splatting (GS) [27] is a recent alternative to neural radiance fields [17,40,44,45,51,81] for learning and rendering 3D objects and scenes. GS represents a scene as a large

To address this shortcoming, in this work, we introduce GES (Generalized Exponential Splatting), a new ap-

- 0.8

- 1.0

Amplitude

Time-Domain Signals

Square Signal

Triangle Signal

Gaussian Signal

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

Frequency

0.0

0.5

1.0

1.5

Magnitude

Frequency-Domain (Fourier Transforms)

Fourier of Square

Fourier of Triangle

Fourier of Gaussian

- Figure 2. The Inherent Low-Pass Limitation of Gaussians. We illustrate the bandwidth constraint of Gaussian functions compared to square and triangle signals. The Gaussian functions’ low-pass property restricts their ability to fit signals with sharp edges that have infinite bandwidth. This limitation constitutes a challenge for 3D Gaussian Splatting [27] in accurately fitting high-bandwidth 3D spatial data.

proach that utilizes the Generalized Exponential Function (GEF) for modeling 3D scenes (Fig.1). Our method is designed to effectively represent signals, especially those with sharp features, which previous Gaussian splatting techniques often smooth out or require extensive splitting to model [27]. Demonstrated in Fig.3, we show that while N = 5 randomly initialized Gaussians are required to fit a square, only 2 GEFs are needed for the same signal. This stems from the fact that Gaussian mixtures have a low-pass frequency domain, while many common signals, like the square, are not band-limited. This high-band modeling constitutes a fundamental challenge to Gaussian-based methods. To help GES to train gradually from low-frequency to high-frequency details, we propose a specialized frequencymodulated image loss. This allows GES to achieve more than 50% reduction in the memory requirement of Gaussian splatting and up to 39% increase in rendering speed while maintaining a competitive performance on standard novel view synthesis benchmarks.

We summarize our contributions as follows:

- • We present principled numerical simulations motivating the use of the Generalized Exponential Functions (GEF) instead of Gaussians for scene modeling.
- • We propose Generalized Exponential Splatting (GES), a novel 3D representation that leverages GEF to develop a splatting-based method for realistic, real-time, and memory-efficient novel view synthesis.
- • Equipped with a specialized frequency-modulated image loss and through extensive experiments on standard benchmarks on novel view synthesis, GES shows a 50% reduction in memory requirement and up to 39% increase in rendering speed for real-time radiance field rendering based on Gaussian Splatting. GES can act as a plug-andplay replacement for any Gaussian-based utilities.

- 2. Related work

0.6

0.4

0.2

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

Time

its 2D RGB images captured from different camera positions [1, 16]. Classical approaches usually recover a scene’s geometry as a point cloud using SIFT-based [39] point matching [61, 63]. More recent methods enhance them by relying on neural networks for feature extraction (e.g. [22, 75, 76, 83]). The development of Neural Radiance Fields (NeRF) [37, 44] has prompted a shift towards reconstructing 3D as volume radiance [66], enabling the synthesis of photo-realistic novel views [4, 5, 69]. Subsequent works have also explored the optimization of NeRF in few-shot (e.g. [15, 23, 28]) and one-shot (e.g. [7, 82]) settings. NeRF does not store any 3D geometry explicitly (only the density field), and several works propose to use a signed distance function to recover a scene’s surface [12, 33, 34, 71, 72, 77, 78], including in the few-shot setting as well (e.g. [84,85]).

Differentiable rendering. Gaussian Splatting is a pointbased rendering [2, 19] algorithm that parameterizes 3D points as Gaussian functions (mean, variance, opacity) with spherical harmonic coefficients for the angular radiance component [80]. Prior works have extensively studied differentiable rasterization, with a series of works [26,36,38] proposing techniques to define a differentiable function between triangles in a triangle mesh and pixels, which allows for adjusting parameters of triangle mesh from observation. These works range from proposing a differentiable renderer for mesh processing with image filters [32], and proposing to blend schemes of nearby triangles [48], to extending differentiable rasterization to large-scale indoor scenes [79]. On the point-based rendering [19] side, neural point-based rendering [26] allows features to be learned and stored in 3D points for geometrical and textural information. Wiles et al. combine neural point-based rendering with an adversarial loss for better photorealism [73], whereas later works use points to represent a radiance field, combining NeRF and point-based rendering [74, 86]. Our GES is a point-based rasterizer in which every point represents a generalized exponential with scale, opacity, and shape, affecting the rasterization accordingly.

Multi-view 3D reconstruction. Multi-view 3D reconstruction aims to recover the 3D structure of a scene from

###### Prior-based 3D reconstruction. Modern zero-shot text-to-

1.0

- = 0.5

- = 1

True square

True square

1.0

Gaussian Mixture

GEF Mixture

- = 1.5

- = 2

- = 3

1.0

0.8

0.8

0.8

= 10

0.6

f(x|)

0.6

0.6

y

y

0.4

0.4

0.4

0.2

0.2

0.2

0.0

0.0

0.0

4 2 0 2 4

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

(a) A family of GEFs fβ(x) (b) Five Gaussians fitting a square (c) Two GEFs fitting a square

β

|x−µ| α

- Figure 3. Generalized Exponential Function (GEF). (a): We show a family of GEFs fβ(x) = Ae−

with different β values for α = 1, µ = 0. When β = 2, the function reduces to the Gaussian function followed in 3D gaussian splatting [27]. In our GES , we learn β as another parameter of each splatting component. (b,c): The proposed GEF mixture, with learnable β, fits the same signal (square) with fewer components compared to Gaussian functions using gradient-based optimizations. (b): We show an example of the fitted mixture with N = 5 components when Gaussians are used vs. (c) when GEF is used with N = 2 components. GEF achieves less error loss (0.44) and approximates sharp edges better than the Gaussian counterpart (0.48 error) with less number of components. The optimized individual components (initialized with random parameters) are shown in green after convergence.

image generators [3,18,55,56,59,60] have improved the results by providing stronger synthesis priors [8,11,42,50,70]. DreamFusion [50] is a seminal work that proposed to distill an off-the-shelf diffusion model [60] into a NeRF [5,44] for a given text query. It sparked numerous follow-up approaches for text-to-3D synthesis (e.g. [9, 30]) and imageto-3D reconstruction (e.g. [13, 35, 41, 64]). The latter is achieved via additional reconstruction losses on the frontal camera position [35] and/or subject-driven diffusion guidance [30,54]. The developed methods improved the underlying 3D representation [9, 30, 67] and 3D consistency of the supervision [35, 65]; explored task-specific priors [21, 24,58] and additional controls [43]. Lately, Gaussian-based methods [68] improved the speed of optimization of 3D generation, utilizing the fast rasterization of Gaussian Splatting. We showcase how our GES can act as a plug-and-play replacement for Gaussian Splatting in this application and other utilities.

#### 3. Properties of Generalized Exponentials

##### 3.1. Generalized Exponential Function

Preliminaries. The Generalized Exponential Function (GEF) is similar to the probability density function (PDF) of the Generalized Normal Distribution (GND) [14]. This function allows for a more flexible adaptation to various data shapes by adjusting the shape parameter β ∈ (0,∞). The GEF is given by:

f(x|µ,α,β,A) = Aexp −

|x − µ| α

β

(1)

where µ ∈ R is the location parameter, α ∈ R is the scale parameter, A ∈ R+ defines a positive amplitude. The behavior of this function is illustrated in Fig.3. For β = 2, the

GEF becomes a scaled Gaussian f(x|µ,α,β = 2,A) = Ae−

2

x−µ α/√2

- 1

- 2

. The GEF, therefore, provides a versatile framework for modeling a wide range of data by varying β, unlike the Gaussian mixtures, which have a low-pass frequency domain. Many common signals, like the square or triangle, are band-unlimited, constituting a fundamental challenge to Gaussian-based methods. In this paper, we try to learn a positive β for every component of the Gaussian splatting to allow for a generalized 3D representation.

Theoretical Results. Despite its generalizable capabilities, the behavior of the GEF cannot be easily studied analytically, as it involves complex integrals of exponentials without closed form that depend on the shape parameter β. We demonstrate in Theorem 1 in the Appendix that for specific cases, such as for a square signal, the GEF can achieve a strictly smaller approximation error than the corresponding Gaussian function by properly choosing β. The proof exploits the symmetry of the square wave signal to simplify the error calculations. Theorem 1 provides a theoretical foundation for preferring the GEF over standard Gaussian functions in our GES representation instead of 3D Gaussian Splatting [27].

##### 3.2. Assessing 1D GEF Mixtures in Simulation

We evaluate the effectiveness of a mixture of GEFs in representing various one-dimensional (1D) signal types. This evaluation is conducted by fitting the model to synthetic signals that replicate characteristics properties of common real-world signals. More details and additional simulation results are provided in the Appendix.

Simulation Setup. The experimental framework was based on a series of parametric models implemented in PyTorch [47], designed to approximate 1D signals using mixtures of

(a) Square signal (b) Parabolic signal (c) Exponential signal

- 10 1

AverageLoss(logscale)

Gaussian

DoG

LoG GEF

2 5 8 10 15 20

Number of Components (N)

10 4

10 3

10 2

10 1

AverageLoss(logscale)

Gaussian

DoG

LoG GEF

2 5 8 10 15 20

Number of Components (N)

10 4

10 3

AverageLoss(logscale)

Gaussian

DoG

LoG GEF

(d) Triangle signal (e) Gaussian signal (f) Half sinusoid signal

2 5 8 10 15 20

Number of Components (N)

10 4

10 3

- 10 2

10 2

10 3

2 5 8 10 15 20

Number of Components (N)

10 2

Gaussian

Gaussian

Gaussian

10 2

AverageLoss(logscale)

AverageLoss(logscale)

AverageLoss(logscale)

DoG

DoG

DoG

10 3

LoG GEF

LoG GEF

LoG GEF

10 3

10 4

10 5

10 4

10 6

10 7

10 5

2 5 8 10 15 20

2 5 8 10 15 20

Number of Components (N)

Number of Components (N)

- Figure 4. Numerical Simulation Results of Different Mixtures. We show a comparison of average loss for different mixture models optimized with gradient-based optimizers across varying numbers of components on various signal types (a-f). In the case of ‘NaN‘ loss ( gradient explosion), the results are not shown on the plots. Full simulation results are provided in the Appendix

different functions such as Gaussian (low-pass), Difference of Gaussians (DoG), Laplacian of Gaussian (LoG), and a GEF mixture model. Each model comprised parameters for means, variances (or scales), and weights, with the generalized model incorporating an additional parameter, β, to control the exponentiation of the GEF function.

Models. In this section, we briefly overview the mixture models employed to approximate true signals. Detailed formulations are provided in the Appendix.

Gaussian Mixture: This model uses a combination of multiple Gaussian functions. Each Gaussian is characterized by its own mean, variance, and weight. The overall model is a weighted sum of these Gaussian functions, which is a low-pass filter.

Difference of Gaussians (DoG) Mixture: The DoG model is a variation of the Gaussian mixture. It is formed by taking the difference between pairs of Gaussian functions with a predefined variance ratio. This model is particularly effective in highlighting contrasts in the signal and is considered a band-pass filter.

Laplacian of Gaussian (LoG) Mixture: This model combines the characteristics of a Laplacian of Gaussian function. Each component in the mixture has specific parameters that control its shape and scale. Just like the DoG, the LoG model is adept at capturing fine details in the signal and is a band-pass filter.

Generalized Exponential (GEF) Mixture: A more flexible version of the Gaussian mixture, this model introduces an additional shape parameter β. By adjusting this parameter, we can fine-tune the model to better fit the characteristics of the signal. The GEF Mixture frequency response depends on the shape parameter β.

Model Configuration. The models were configured with a varying number of components N, with tests conducted using N = {2,5,8,10,15,20}. The weights of the components are chosen to be positive. All the parameters of all the N components were learned. Each model was trained using the Adam optimizer with a mean squared error loss function. The input x was a linearly spaced tensor representing the domain of the synthetic signal, and the target y was the value of the signal at each point in x. Training proceeded for a predetermined number of epochs, and the loss was recorded at the end of training.

Data Generation. Synthetic 1D signals were generated for various signal types over a specified range, with a given data size and signal width. The signals were used as the ground truth for training the mixture models. The ground truth signals used in the experiment are one-dimensional (1D) functions that serve as benchmarks for evaluating signal processing algorithms. The signal types under study are: square, triangle, parabolic, half sinusoidal, Gaussian, and exponential functions. We show Fig.3 an example of fitting a Gaussian when N = 5 and a Generalized mixture on the square signal when N = 2. Note how sharp edges constitute a challenge for Gaussians that have low pass bandwidth while a square signal has an infinite bandwidth known by the sinc function [25].

Simulation Results. The models’ performance was evaluated based on the loss value after training. Additionally, the model’s ability to represent the input signal was visually inspected through generated plots. Multiple runs per configuration were executed to account for variance in the results. For a comprehensive evaluation, each configuration was run multiple times (20 runs per configuration) to account for

Ground Truth GES (Ours) Gaussians Mip-NeRF360 InstantNGP

[Figure 19]

[Figure 20]

[Figure 21]

[Figure 22]

[Figure 23]

[Figure 24]

[Figure 25]

[Figure 26]

[Figure 27]

[Figure 28]

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

[Figure 29]

[Figure 30]

[Figure 31]

[Figure 32]

[Figure 33]

[Figure 34]

[Figure 35]

[Figure 36]

[Figure 37]

[Figure 38]

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

[Figure 39]

[Figure 40]

[Figure 41]

[Figure 42]

[Figure 43]

[Figure 44]

[Figure 45]

[Figure 46]

[Figure 47]

[Figure 48]

- Figure 5. Visual Comparison on Novel View Synthesis. We display comparisons between our proposed method and established baselines alongside their respective ground truth images. The depicted scenes are ordered as follows: GARDEN and ROOM from the Mip-NeRF360 dataset; DRJOHNSON from the Deep Blending dataset; and TRAIN from Tanks&Temples. Subtle differences in rendering quality are accentuated through zoomed-in details. These specific scenes were picked similarly to Gaussin Splatting [27] for a fair comparison. It might be difficult in general to see differences between GES and Gaussians because they have almost the same PSNR (despite GES requiring 50% less memory).

variability in the training process. During these runs, the number of instances where the training resulted in a ’nan’ loss was removed from the loss plots, and hence some plots in Fig.4 do not have loss values at some N. As depicted in Fig.4, the GEF Mixture consistently yielded the lowest loss across the number of components, indicating its effective approximation of many common signals, especially bandunlimited signals like the square and triangle. The only exception is the Gaussian signal, which is (obviously) fitted better with a Gaussian Mixture.

#### 4. Generalized Exponential Splatting (GES)

Having established the benefits of GEF of Eq.(1) over Gaussian functions, we will now demonstrate how to extend GEF into the Generalized Exponential Splatting (GES) framework, offering a plug-and-play replacement for Gaussian Splatting. We also start with a collection of static images of a scene and their corresponding camera calibrations obtained through Structure from Motion (SfM) [62], which additionally provides a sparse point cloud. Moving beyond Gaussian models [27], GES adopts an exponent β to tailor the focus of the splats, thus sharpening the delineation of scene edges. This technique is not only more efficient in memory usage but also can surpass Gaussian splatting in

established benchmarks for novel view synthesis.

##### 4.1. Differentiable GES Formulation

Our objective is to enhance novel view synthesis with a refined scene representation. We leverage a generalized exponential form, here termed Generalized Exponential Splatting, which for location x in 3D space and a positive definite matrix Σ, is defined by:

- 1

- 2

β 2

(x − µ)⊺Σ−1(x − µ)

L(x;µ,Σ,β) = exp −

,

(2) where µ is the location parameter and Σ is the covariance matrix equivalance in Gaussian Splatting [27]. β is a shape parameter that controls the sharpness of the splat. When β = 2, this formulation is equivalent to Gaussian splatting [27]. Our approach maintains an opacity measure κ for blending and utilizes spherical harmonics for coloring, similar to Gaussian splatting [27].

For 2D image projection, we adapt the technique by Zwicker et al. [88], but keep track of our variable exponent β. The camera-space covariance matrix Σ′ is transformed as follows: Σ′ = JWΣW⊺J⊺, where J is the Jacobian of the transformation from world to camera space, and W is a diagonal matrix containing the inverse square root of the

[Figure 49]

eigenvalues of Σ. We ensure Σ remains positively semidefinite throughout the optimization by formulating it as a product of a scaling matrix S (modified by some positive modification function ϕ(β) > 0 as we show later) and a rotation matrix R, with optimization of these components facilitated through separate 3D scale vectors s and quaternion rotations q.

### r

[Figure 50]

[Figure 51]

[Figure 52]

Center

[Figure 53]

[Figure 54]

[Figure 55]

##### 4.2. Fast Differentiable Rasterizer for Generalized Exponential Splats

[Figure 56]

[Figure 57]

[Figure 58]

[Figure 59]

Intuition from Volume Rendering. The concept of volume rendering in the context of neural radiance fields [44] involves the integration of emitted radiance along a ray passing through a scene. The integral equation for the expected color C(r) of a camera ray r(t) = o + td, with near and far bounds tn and tf, respectively, is given by:

Original (𝛽=2) Modified (𝛽>2)

[Figure 60]

Effective projected variance (𝒂∧)

Figure 6. Effective Variance of GES components. We demonstrate the concept of effective variance projection α(β) for an individual splatting component intersecting a camera ray r under shape modification (β > 2). Note that α(β) is a scaled version of the original splat projected variance α.

tf

C(r) =

T(t)κ(r(t))c(r(t),d)dt,

tn

(3)

t

where T(t) = exp −

κ(r(s))ds .

the variance of the generalized exponential distribution and the variance of the Gaussian distribution is given by [14] as

tn

Here, T(t) represents the transmittance along the ray from

Γ(3/β) Γ(1/β)

- tn to t, κ(r(t)) is the volume density, and c(r(t),d) is the emitted radiance at point r(t) in the direction d. The total

(5)

ϕ(β) =

distance [tn,tf] crossed by the ray across non-empty space dictates the amount of lost energy and hence the reduction of the intensity of the rendered colors. In the Gaussian Splatting world [27], this distance [tn,tf] is composed of the projected variances α of each component along the ray direction o + td. In our GES of Eq.(2), if the shape parameter β of some individual component changes, the effective impact on Eq.(3) will be determined by the effective variance projection α of the same component modified by the modifcation function ϕ(β) as follows:

, where Γ is the Gamma function. This conversion in Eq.(5) ensures the PDF integrates to 1. In a similar manner, the integrals in Eq.(3) under Eq.(4) can be shown to be equivalent for Gaussians and GES using the same modification of Eq.(5). The modification will affect the rasterization as if we did perform the exponent change. It is a trick that allows using generalized exponential rasterization without taking the β exponent. Similarly, the Gaussian splatting [27] is not learning rigid Gaussians, it learns properties of point clouds that act as if there are Gaussians placed there when they splat on the image plane. Both our GES and Gaussians are in the same spirit of splatting, and representing 3D with splat properties. Fig.6 demonstrates this concept for an individual splatting component intersecting a ray r from the camera and the idea of effective variance projection α. However, as can be in Fig.6, this scaler modification ϕ(β) introduces some view-dependent boundary effect error (e.g. if the ray r passed on the diagonal). We provide an upper bound estimate on this error in the Appendix.

###### α(β) = ϕ(β)α . (4)

Note that the modification function ϕ we chose does not depend on the ray direction since the shape parameter β is a global property of the splatting component, and we assume the scene to comprise many components. We tackle next the choice of the modification function ϕ and how it fits into the rasterization framework of Gaussian Splatting [27].

Approximate Rasterization. The main question is how to represent the GES in the rasterization framework. In effect, the rasterization in Gaussian Splatting [27] only relies on the variance splats of each component. So, we only need to simulate the effect of the shape parameter β on the covariance of each component to get the rasterization of GES . To do that, we modify the scales matrix of the covariance in each component by the scaler function ϕ(β) of that component. From probability theory, the exact conversion between

Due to the instability of the Γ function in Eq.(5), we can approximate ϕ(β) with the following smooth function.

2

ϕ¯ρ(β) =

1 + e−(ρβ−2ρ) . (6) The difference between the exact modification ϕ(β) and the approximate ϕ¯ρ(β) ( controlled by the hyperparameter shape strength ρ ) is shown in Fig.7. At β = 2 (Gaussian shape), the modifications ϕ and ϕ¯ are exactly 1. This

2.00

Exact

Approximate ( =0.1)

1.75

- Approximate ( =0.5)

- Approximate ( =1.0)

GeneralizedVariance

1.50

Approximate ( =10)

1.25

1.00

0.75

0.50

0.25

0.00

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

values

- Figure 7. The Modification Function ϕ(β). We show different ρ shape strength values of the approximate functions ϕ¯ρ(β) in Eq.(6) and the exact modification function ϕ(β) in Eq.(5). At β = 2 ( gaussian splats), all functions have a variance modification of 1, and GES reduces to Gaussian Splatting. In the extreme case of ρ = 0, GES reduces to Gaussian Splatting for any β.

parameterization ϕ¯ρ(β) ensures that the variance of each component remains positive.

##### 4.3. Frequency-Modulated Image Loss

To effectively utilize the broad-spectrum capabilities of GES , it has been enhanced with a frequency-modulated image loss, denoted as Lω. This loss is grounded in the rationale that GES , initially configured with Gaussian low-pass band splats, should primarily concentrate on low-frequency details during the initial stages of training. As training advances, with the splat formations adapting to encapsulate higher frequencies, the optimization’s emphasis should gradually shift towards these higher frequency bands within the image. This concept bears a technical resemblance to the frequency modulation approach used in BARF [31], albeit applied within the image domain rather than the 3D coordinate space. The loss is guided by a frequencyconditioned mask implemented via a Difference of Gaussians (DoG) filter to enhance edge-aware optimization in image reconstruction tasks modulated by the normalized frequency ω. The DoG filter acts as a band-pass filter, emphasizing the edges by subtracting a blurred version of the image from another less blurred version, thus approximating the second spatial derivative of the image. This operation is mathematically represented as:

DoG(I) = G(I,σ1) − G(I,σ2), 0 < σ2 < σ1

where G(I,σ) denotes the Gaussian blur operation on image I with standard deviation σ. The choice of σ values dictates the scale of edges to be highlighted, effectively determining the frequency band of the filter. We chose σ1 = 2σ2

- to ensure the validity of the band-pass filter, where the

choice of σ2 will determine the target frequency band of the filter. In our formulation, we use predetermined target

normalized frequencies ω ( ω = 0% for low frequencies to ω = 100% for high frequencies). We chose σ2 = 0.1+10ω to ensure the stability of the filter and reasonable resulting masks. The filtered image is then used to generate an edge-aware mask Mω through a pixel-wise comparison to a threshold value (after normalization) as follows.

Mω = DoGω(Igt)normalized > ϵω , DoGω(I) = G(I,0.2 + 20ω) − G(I,0.1 + 10ω)

(7)

, where 0 ≤ ϵω ≤ 1 is the threshold ( we pick 0.5) for a normalized response of the filter DoGω, Igt is the ground truth image, and is the indicator function. See Fig.8 for examples of the masks. The edge-aware frequency-modulated loss Lω is defined as:

Lω = ∥(I − Igt) · Mω∥1, (8)

where I is the reconstructed image, and ∥·∥1 denotes the L1 norm. This term is integrated into the overall loss, as shown later. The mask is targeted for the specified frequencies ω. We use a linear schedule to determine these target ω values in Eq.(8) and Eq.(7) during the optimization of GES , ω = current iteration

total iterations . The loss Lω aims to help in tuning the shape β based on the nature of the scene. It does so by focusing the GES components on low pass signals first during the training before focusing on high frequency with tuning β from their initial values. This helps the efficiency of GES as can be seen later in Table 6 (almost free 9% reduction in memory).

Due to DoG filter sensitivity for high-frequencies, the mask for 0% < ω ≤ 50% is defined as 1 − Mω of 50% < ω ≤ 100%. This ensures that all parts of the image will be covered by one of the masks Mω, while focusing on the details more as the optimization progresses.

##### 4.4. Optimization of the Generalized Exponential Splats

We detail a novel approach for controlling shape density, which selectively prunes GES according to their shape attributes, thus eliminating the need for a variable density mechanism. This optimization strategy encompasses the β parameter as well as the splat’s position x, opacity κ, covariance matrix Σ, and color representation through spherical harmonics coefficients [27]. Optimization of these elements is conducted using stochastic gradient descent, with the process accelerated by GPU-powered computation and specialized CUDA kernels.

Starting estimates for Σ and x are deduced from the SfM points, while all β values are initialized with β = 2 (pure Gaussian spalts). The loss function integrates an L1 metric combined with a structural similarity loss (SSIM), and the frequency-modulated lossLω:

L = λL1L1 + λssimLssim + λωLω, (9)

[Figure 61]

[Figure 62]

[Figure 63]

[Figure 64]

- Figure 8. Frequency-Modulated Image Masks. For the input example image on the left, We show examples of the frequency loss masks Mω used in Sec.4.3 for different numbers of target normalized frequencies ω ( ω = 0% for low frequencies to ω = 100% for high frequencies). This masked loss helps our GES learn specific bands of frequencies. We use a linear schedule to determine these target

ω values during the optimization of GES , ω = currenttotaliterationsiteration. Note that due to DoG filter sensitivity for high-frequencies, the mask for 0 < ω ≤ 50% is defined as 1 − Mω of 50 < ω ≤ 100%. This ensures that all parts of the image will be covered by one of the masks Mω, while focusing on the details more as the optimization progresses.

where λssim = 0.2 is applied uniformly in all evaluations, and λL1 = 1−λssim −λω. Expanded details on the learning algorithm and other specific procedural elements are available in the Appendix.

#### 5. Experiments

##### 5.1. Datasets and Metrics

In our experiments, we utilized a diverse range of datasets to test the effectiveness of our algorithm in rendering real-world scenes. This evaluation encompassed 13 real scenes from various sources. We particularly focused on scenes from the Mip-Nerf360 dataset [5], renowned for its superior NeRF rendering quality, alongside select scenes from the Tanks & Temples dataset [29], and instances provided by Hedman et al. [20] for their work in Deep Blending. These scenes presented a wide array of capture styles, ranging from bounded indoor settings to expansive unbounded outdoor environments.

The quality benchmark in our study was set by the MipNerf360 [4], which we compared against other contemporary fast NeRF methods, such as InstantNGP [45] and Plenoxels. Our train/test split followed the methodology recommended by Mip-NeRF360, using every 8th photo for testing. This approach facilitated consistent and meaningful error metric comparisons, including standard measures such as PSNR, L-PIPS, and SSIM, as frequently employed in existing literature (see Table 1). Our results encompassed various configurations and iterations, highlighting differences in training time, rendering speeds, and memory requirements for optimized parameters.

##### 5.2. Implementation Details of GES

Our methodology maintained consistent hyperparameter settings across all scenes, ensuring uniformity in our evaluations. We deployed an A6000 GPU for most of our tests. Our Generalized Exponential Splatting (GES ) was implemented over 40,000 iterations, and the density gradient threshold is set to 0.0003. The learning rate for the shape

parameter was set at 0.0015, with a shape reset interval of 1000 iterations and a shape pruning interval of 100 iterations. The threshold for pruning based on shape was set at 0.5, while the shape strength parameter was determined to be 0.1, offering a balance between accuracy and computational load. Additionally, the Image Laplacian scale factor was set at 0.2, with the corresponding λω frequency loss coefficient marked at 0.5, ensuring edge-enhanced optimization in our image reconstruction tasks. The other hyperparameters and design choices (like opacity splitting and pruning) shared with Gaussian splitting [27] were kept the same. More details are provided in the Appendix.

#### 6. Results

##### 6.1. Novel View Synthesis Results

We evaluated GES against several state-of-the-art techniques in both novel view synthesis tasks. Table 1 encapsulate the comparative results in addition to Fig.5. Table 1 demonstrates that GES achieves a balance between high fidelity and efficiency in novel view synthesis. Although it does not always surpass other methods in SSIM or PSNR, it significantly excels in memory usage and speed. With only 377MB of memory and a processing speed of 2 minutes, GES stands out as a highly efficient method, particularly when compared to the 3D Gaussians-30K and Instant NGP, which require substantially more memory or longer processing times. Overall, the results underscore GES ’s capability to deliver balanced performance with remarkable efficiency, making it a viable option for real-time applications that demand both high-quality output and operational speed and memory efficiency.

Note that it is difficult to see the differences in visual effects between GES and Gaussians in Fig.5 since they have almost the same PSNR but a different file size (Table 1). For a fair visual comparison, we restrict the number of components to be roughly the same (by controlling the splitting of Gaussians) and show the results in Fig.9. It clearly shows that GES can model tiny and sharp edges for that scene bet-

|Dataset Method—Metric|Mip-NeRF360 Dataset<br><br>SSIM↑ PSNR↑ LPIPS↓ Train↓ FPS↑ Mem↓<br><br>|Tanks&Temples<br><br>SSIM↑ PSNR↑ LPIPS↓ Train↓ FPS↑ Mem↓|Deep Blending<br><br>SSIM↑ PSNR↑ LPIPS↓ Train↓ FPS↑ Mem↓|
|---|---|---|---|
|Plenoxels INGP Mip-NeRF360 3D Gaussians-7K 3D Gaussians-30K<br><br>|0.626 23.08 0.463 26m 6.79 2.1GB 0.699 25.59 0.331 7.5m 9.43 48MB 0.792 27.69 0.237 48h 0.06 8.6MB 0.770 25.60 0.279 6.5m 160 523MB 0.815 27.21 0.214 42m 134 734MB<br><br>|0.719 21.08 0.379 25m 13.0 2.3GB 0.745 21.92 0.305 7m 14.4 48MB 0.759 22.22 0.257 48h 0.14 8.6MB 0.767 21.20 0.280 7m 197 270MB 0.841 23.14 0.183 26m 154 411MB<br><br>|0.795 23.06 0.510 28m 11.2 2.7GB 0.817 24.96 0.390 8m 2.79 48MB 0.901 29.40 0.245 48h 0.09 8.6MB 0.875 27.78 0.317 4.5m 172 386MB 0.903 29.41 0.243 36m 137 676MB<br><br>|

GES (ours) 0.794 26.91 0.250 32m 186 377MB 0.836 23.35 0.198 21m 210 222MB 0.901 29.68 0.252 30m 160 399MB

Table 1. Comparative Analysis of Novel View Synthesis Techniques. This table presents a comprehensive comparison of our approach with established methods across various datasets. The metrics, inclusive of SSIM, PSNR, and LPIPS, alongside training duration, frames per second, and memory usage, provide a multidimensional perspective of performance efficacy. Note that our training time numbers of the different methods may be computed on different GPUs; they are not necessarily perfectly comparable but are still valid. Note that non-explicit representations (INGP, Mip-NeRF360) have low memory because they rely on additional slow neural networks for decoding. Red-colored results are the best.

Ground Truth GES(ours) Gaussians

Ablation Setup PSNR↑ SSIM↑ LPIPS↓ Size (MB)↓

[Figure 65]

[Figure 66]

[Figure 67]

| |
|---|

| |
|---|

| |
|---|

Gaussians 27.21 0.815 0.214 734 GES w/o approx. ϕ¯ρ 11.60 0.345 0.684 364 GES w/o shape reset 26.57 0.788 0.257 374 GES w/o Lω loss 27.07 0.800 0.250 411 Full GES 26.91 0.794 0.250 377

[Figure 68]

[Figure 69]

[Figure 70]

| |
|---|

| |
|---|

| |
|---|

- Figure 9. Fair Visual Comparison. We show an example of Gaussians [27] and GES when constrained to the same number of splatting components for a fair visual comparison. It clearly shows that GES can model tiny and sharp edges for that scene better than Gaussians.

Table 2. Ablation Study on Novel View Synthesis. We study the impact of several components in GES on the reconstruction quality and file size in the Mip-NeRF360 dataset.

ter than Gaussians.

##### 6.2. Ablation and analysis

Shape parameters. In Table 2, we explore the effect of important hyperparameters associated with the new shape parameter on novel view synthesis performance. We see that proper approximation ϕ¯ρ in Eq.(6) is necessary, because if we set ρ = 10 for ϕ¯ρ to be as close to the exact ϕ(β) (Fig.7), the PSNR would drop to 11.6. Additional detailed analysis is provided in the Appendix.

Effect of frequency-modulated image loss. We study the effect of the frequency loss Lω introduced in Sec.4.3 on the performance by varying λω. In table 2 and in Fig.10 we demonstrate how adding this Lω improves the optimization in areas where large contrast exists or where the smooth background is rendered and also improves the efficiency of GES. We notice that increasing λω in GES indeed reduces the size of the file, but can affect the performance. We chose λω = 0.5 as a middle ground between improved performance and reduced file size.

Analyzing memory reduction. We find that the reduction in memory after learning β is indeed attributed to the reduction of the number of components needed. For example, in the “Train” sequence, the number of components is 1,087,264 and 548,064 for Gaussian splatting and GES respectively. This translates into the reduction of file size from 275 MB to 129.5 MB when utilizing GES .

Applying GES in fast 3D generation. Recent works have proposed to use Gaussian Splatting for 3D generation

pipelines such as DreamGaussian [68] and Text-to-3D using Gaussian Splatting [10]. Integrating GES into these Gaussian-based 3D generation pipelines has yielded fast and compelling results with a plug-and-play ability of GES in place of Gaussian Splatting (see Fig.11).

#### 7. Conclusion and discussion

This paper introduced GES (Generalized Exponential Splatting), a new technique for 3D scene modeling that improves upon Gaussian Splatting in memory efficiency and signal representation, particularly for high-frequency signals. Our empirical results demonstrate its efficacy in novel view synthesis and 3D generation tasks.

Limitation. One obvious limitation in our approach is that performance typically drops trying to make the representation as memor-efficient and as compact as possible. This is more noticeable for more complex scenes due to the pruning operations that depend on β-tuning. Removing many of the components can eventually drop the PSNR performance (Table 1 last 2 rows). Future research could focus on enhancing GES ’s performance in more complex and dynamic environments and exploring its integration with other technologies in 3D modeling.

#### References

[1] Sameer Agarwal, Yasutaka Furukawa, Noah Snavely, Ian Simon, Brian Curless, Steven M Seitz, and Richard Szeliski. Building rome in a day. Communications of the ACM, 54(10):105–112, 2011. 2

Ground Truth GES (full) GES (w/o Lω ) Gaussian Splatting [27]

[Figure 71]

[Figure 72]

[Figure 73]

[Figure 74]

| |
|---|

| |
|---|

| |
|---|

| |
|---|

[Figure 75]

[Figure 76]

[Figure 77]

[Figure 78]

| |
|---|

| |
|---|

| |
|---|

| |
|---|

- Figure 10. Frequency-Modulated Loss Effect. We show the effect of the frequency-modulated image loss Lω on the performance on novel views synthesis. Note how adding this Lω improves the optimization in areas where a large contrast exists or a smooth background is rendered.

Realfusion15 NeRF4 StableDiffusion-XL

[Figure 79]

- [7] Eric R Chan, Connor Z Lin, Matthew A Chan, Koki Nagano, Boxiao Pan, Shalini De Mello, Orazio Gallo, Leonidas J Guibas, Jonathan Tremblay, Sameh Khamis, et al. Efficient geometry-aware 3d generative adversarial networks. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 16123–16133, 2022. 2
- [8] Dave Zhenyu Chen, Yawar Siddiqui, Hsin-Ying Lee, Sergey Tulyakov, and Matthias Nießner. Text2tex: Text-driven texture synthesis via diffusion models. arXiv preprint arXiv:2303.11396, 2023. 3
- [9] Rui Chen, Yongwei Chen, Ningxin Jiao, and Kui Jia. Fantasia3d: Disentangling geometry and appearance for high-quality text-to-3d content creation. arXiv preprint arXiv:2303.13873, 2023. 3
- [10] Zilong Chen, Feng Wang, and Huaping Liu. Text-to-3d using gaussian splatting. arXiv preprint arXiv:2309.16585, 2023. 9
- [11] Yen-Chi Cheng, Hsin-Ying Lee, Sergey Tulyakov, Alexander G Schwing, and Liang-Yan Gui. Sdfusion: Multimodal 3d shape completion, reconstruction, and generation. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2023. 3
- [12] Fran¸cois Darmon, B´en´edicte Bascle, Jean-Cl´ement Devaux, Pascal Monasse, and Mathieu Aubry. Improving neural implicit surfaces geometry with patch warping. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 6260–6269, 2022. 2
- [13] Matt Deitke, Ruoshi Liu, Matthew Wallingford, Huong Ngo, Oscar Michel, Aditya Kusupati, Alan Fan, Christian Laforte, Vikram Voleti, Samir Yitzhak Gadre, et al. Objaverse-xl: A universe of 10m+ 3d objects. arXiv preprint arXiv:2307.05663, 2023. 3
- [14] J Armando Dominguez-Molina, Graciela Gonz´alez-Far´ıas, Ram´on M Rodr´ıguez-Dagnino, and ITESM Campus Monterrey. A practical procedure to estimate the shape parameter in the generalized gaussian distribution. available through link https://www.cimat.mx/BiblioAdmin/RTAdmin/reportes/enlinea/I01-18 eng.pdf, 1, 2003. 3, 6, 14, 31

- [15] Yilun Du, Cameron Smith, Ayush Tewari, and Vincent Sitzmann. Learning to render novel views from wide-baseline stereo pairs. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2023. 2
- [16] Olivier D Faugeras. What can be seen in three dimensions with an uncalibrated stereo rig? In Computer Vi-

Reference

Source view

- Novel view 1
- Novel view 2

Figure 11. GES Application: Fast Image-to-3D Generation. We show selected 3D generated examples from Co3D images [57] by combining GES with the Gaussian-based 3D generation pipeline [68], highlighting the plug-and-play benefits of GES to replace Gaussian Splatting [27].

- [2] Kara-Ali Aliev, Artem Sevastopolsky, Maria Kolos, Dmitry Ulyanov, and Victor Lempitsky. Neural point-based graphics. In Computer Vision–ECCV 2020: 16th European Conference, Glasgow, UK, August 23–28, 2020, Proceedings, Part XXII 16, pages 696–712. Springer, 2020. 2
- [3] Yogesh Balaji, Seungjun Nah, Xun Huang, Arash Vahdat, Jiaming Song, Karsten Kreis, Miika Aittala, Timo Aila, Samuli Laine, Bryan Catanzaro, et al. ediffi: Text-to-image diffusion models with an ensemble of expert denoisers. arXiv preprint arXiv:2211.01324, 2022. 3
- [4] Jonathan T Barron, Ben Mildenhall, Matthew Tancik, Peter Hedman, Ricardo Martin-Brualla, and Pratul P Srinivasan. Mip-nerf: A multiscale representation for anti-aliasing neural radiance fields. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 5855–5864, 2021. 2, 8
- [5] Jonathan T. Barron, Ben Mildenhall, Dor Verbin, Pratul P. Srinivasan, and Peter Hedman. Mip-nerf 360: Unbounded anti-aliased neural radiance fields. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 5470–5479, June 2022. 2, 3, 8, 32, 38
- [6] Jonathan T. Barron, Ben Mildenhall, Dor Verbin, Pratul P. Srinivasan, and Peter Hedman. Zip-nerf: Anti-aliased gridbased neural radiance fields. ICCV, 2023. 32

- sion—ECCV’92: Second European Conference on Computer Vision Santa Margherita Ligure, Italy, May 19–22, 1992 Proceedings 2, pages 563–578. Springer, 1992. 2
- [17] Sara Fridovich-Keil, Alex Yu, Matthew Tancik, Qinhong Chen, Benjamin Recht, and Angjoo Kanazawa. Plenoxels: Radiance fields without neural networks. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 5501–5510, June 2022. 1
- [18] Oran Gafni, Adam Polyak, Oron Ashual, Shelly Sheynin, Devi Parikh, and Yaniv Taigman. Make-a-scene: Scenebased text-to-image generation with human priors. In Proceedings of the European Conference on Computer Vision (ECCV), pages 89–106, 2022. 3
- [19] Markus Gross and Hanspeter Pfister. Point-based graphics. Elsevier, 2011. 2
- [20] Peter Hedman, Julien Philip, True Price, Jan-Michael Frahm, George Drettakis, and Gabriel Brostow. Deep blending for free-viewpoint image-based rendering. ACM Trans. on Graphics (TOG), 37(6), 2018. 8
- [21] Lukas H¨ollein, Ang Cao, Andrew Owens, Justin Johnson, and Matthias Nießner. Text2room: Extracting textured 3d meshes from 2d text-to-image models. arXiv preprint arXiv:2303.11989, 2023. 3
- [22] Po-Han Huang, Kevin Matzen, Johannes Kopf, Narendra Ahuja, and Jia-Bin Huang. Deepmvs: Learning multi-view stereopsis. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 2821–2830, 2018. 2
- [23] Ajay Jain, Matthew Tancik, and Pieter Abbeel. Putting nerf on a diet: Semantically consistent few-shot view synthesis. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 5885–5894,

2021. 2

- [24] Tomas Jakab, Ruining Li, Shangzhe Wu, Christian Rupprecht, and Andrea Vedaldi. Farm3d: Learning articulated 3d animals by distilling 2d diffusion. arXiv preprint arXiv:2304.10535, 2023. 3
- [25] A.J. Jerri. The shannon sampling theorem—its various extensions and applications: A tutorial review. Proceedings of the IEEE, 65(11):1565–1596, 1977. 4, 17
- [26] Hiroharu Kato, Yoshitaka Ushiku, and Tatsuya Harada. Neural 3d mesh renderer. In Proceedings of the IEEE conference on computer vision and pattern recognition, pages 3907– 3916, 2018. 2
- [27] Bernhard Kerbl, Georgios Kopanas, Thomas Leimk¨uhler, and George Drettakis. 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics, 42(4), July 2023. 1, 2, 3, 5, 6, 7, 8, 9, 10, 14, 16, 17, 32, 33, 38, 39
- [28] Mijeong Kim, Seonguk Seo, and Bohyung Han. Infonerf: Ray entropy minimization for few-shot neural volume rendering. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 12912–12921, 2022. 2
- [29] Arno Knapitsch, Jaesik Park, Qian-Yi Zhou, and Vladlen Koltun. Tanks and temples: Benchmarking large-scale scene reconstruction. ACM Transactions on Graphics, 36(4), 2017.

8

- [30] Chen-Hsuan Lin, Jun Gao, Luming Tang, Towaki Takikawa, Xiaohui Zeng, Xun Huang, Karsten Kreis, Sanja Fidler, Ming-Yu Liu, and Tsung-Yi Lin. Magic3d: High-resolution text-to-3d content creation. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2023. 3
- [31] Chen-Hsuan Lin, Wei-Chiu Ma, Antonio Torralba, and Simon Lucey. Barf: Bundle-adjusting neural radiance fields. In IEEE International Conference on Computer Vision (ICCV),

2021. 7

- [32] Hsueh-Ti Derek Liu, Michael Tao, and Alec Jacobson. Paparazzi: surface editing by way of multi-view image processing. ACM Trans. Graph., 37(6):221–1, 2018. 2
- [33] Ruoshi Liu, Sachit Menon, Chengzhi Mao, Dennis Park, Simon Stent, and Carl Vondrick. What you can reconstruct from a shadow. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 17059– 17068, 2023. 2
- [34] Ruoshi Liu and Carl Vondrick. Humans as light bulbs: 3d human reconstruction from thermal reflection. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 12531–12542, 2023. 2
- [35] Ruoshi Liu, Rundi Wu, Basile Van Hoorick, Pavel Tokmakov, Sergey Zakharov, and Carl Vondrick. Zero-1-to3: Zero-shot one image to 3d object. arXiv preprint arXiv:2303.11328, 2023. 3
- [36] Shichen Liu, Tianye Li, Weikai Chen, and Hao Li. Soft rasterizer: A differentiable renderer for image-based 3d reasoning. In Proceedings of the IEEE/CVF International Conference on Computer Vision, pages 7708–7717, 2019. 2
- [37] Stephen Lombardi, Tomas Simon, Jason Saragih, Gabriel Schwartz, Andreas Lehrmann, and Yaser Sheikh. Neural volumes: Learning dynamic renderable volumes from images. arXiv preprint arXiv:1906.07751, 2019. 2
- [38] Matthew M Loper and Michael J Black. Opendr: An approximate differentiable renderer. In Computer Vision– ECCV 2014: 13th European Conference, Zurich, Switzerland, September 6-12, 2014, Proceedings, Part VII 13, pages 154–169. Springer, 2014. 2
- [39] David G Lowe. Distinctive image features from scaleinvariant keypoints. International Journal of Computer Vision (IJCV), 60:91–110, 2004. 2
- [40] Ricardo Martin-Brualla, Noha Radwan, Mehdi SM Sajjadi, Jonathan T Barron, Alexey Dosovitskiy, and Daniel Duckworth. Nerf in the wild: Neural radiance fields for unconstrained photo collections. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 7210–7219, 2021. 1
- [41] Luke Melas-Kyriazi, Christian Rupprecht, Iro Laina, and Andrea Vedaldi. Realfusion: 360{\deg} reconstruction of any object from a single image. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2023. 3, 32
- [42] Gal Metzer, Elad Richardson, Or Patashnik, Raja Giryes, and Daniel Cohen-Or. Latent-nerf for shape-guided generation of 3d shapes and textures. arXiv preprint arXiv:2211.07600,

2022. 3

- [43] Aryan Mikaeili, Or Perel, Daniel Cohen-Or, and Ali Mahdavi-Amiri. Sked: Sketch-guided text-based 3d editing. arXiv preprint arXiv:2303.10735, 2023. 3
- [44] Ben Mildenhall, Pratul P Srinivasan, Matthew Tancik, Jonathan T Barron, Ravi Ramamoorthi, and Ren Ng. Nerf: Representing scenes as neural radiance fields for view synthesis. In Proceedings of the European Conference on Computer Vision (ECCV), pages 405–421. Springer, 2020. 1, 2, 3, 6
- [45] Thomas M¨uller, Alex Evans, Christoph Schied, and Alexander Keller. Instant neural graphics primitives with a multiresolution hash encoding. ACM Trans. Graph., 41(4):102:1– 102:15, July 2022. 1, 8
- [46] Alex Nichol, Heewoo Jun, Prafulla Dhariwal, Pamela Mishkin, and Mark Chen. Point-e: A system for generating 3d point clouds from complex prompts. arXiv preprint arXiv:2212.08751, 2022. 32
- [47] Adam Paszke, Sam Gross, Francisco Massa, Adam Lerer, James Bradbury, Gregory Chanan, Trevor Killeen, Zeming Lin, Natalia Gimelshein, Luca Antiga, et al. PyTorch: An imperative style, high-performance deep learning library. In Advances in Neural Information Processing Systems (NeurIPS), 2019. 3
- [48] Felix Petersen, Amit H Bermano, Oliver Deussen, and Daniel Cohen-Or. Pix2vex: Image-to-geometry reconstruction using a smooth differentiable renderer. arXiv preprint arXiv:1903.11149, 2019. 2
- [49] Dustin Podell, Zion English, Kyle Lacey, Andreas Blattmann, Tim Dockhorn, Jonas M¨uller, Joe Penna, and Robin Rombach. Sdxl: Improving latent diffusion models for high-resolution image synthesis, 2023. 33
- [50] Ben Poole, Ajay Jain, Jonathan T Barron, and Ben Mildenhall. Dreamfusion: Text-to-3d using 2d diffusion. International Conference on Learning Representations (ICLR),

2022. 3, 32

- [51] Albert Pumarola, Enric Corona, Gerard Pons-Moll, and Francesc Moreno-Noguer. D-nerf: Neural radiance fields for dynamic scenes. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 10318–10327, 2021. 1
- [52] Guocheng Qian, Jinjie Mai, Abdullah Hamdi, Jian Ren, Aliaksandr Siarohin, Bing Li, Hsin-Ying Lee, Ivan Skorokhodov, Peter Wonka, Sergey Tulyakov, and Bernard Ghanem. Magic123: One image to high-quality 3d object generation using both 2d and 3d diffusion priors. arXiv preprint arXiv:2306.17843, 2023. 32
- [53] Alec Radford, Jong Wook Kim, Chris Hallacy, Aditya Ramesh, Gabriel Goh, Sandhini Agarwal, Girish Sastry, Amanda Askell, Pamela Mishkin, Jack Clark, et al. Learning transferable visual models from natural language supervision. In Proceedings of the International Conference on Machine Learning (ICML), pages 8748–8763. PMLR, 2021. 32
- [54] Amit Raj, Srinivas Kaza, Ben Poole, Michael Niemeyer, Nataniel Ruiz, Ben Mildenhall, Shiran Zada, Kfir Aberman, Michael Rubinstein, Jonathan Barron, et al. Dreambooth3d: Subject-driven text-to-3d generation. arXiv

preprint arXiv:2303.13508, 2023. 3

- [55] Aditya Ramesh, Prafulla Dhariwal, Alex Nichol, Casey Chu, and Mark Chen. Hierarchical text-conditional image generation with clip latents. arXiv preprint arXiv:2204.06125,

2022. 3

- [56] Aditya Ramesh, Mikhail Pavlov, Gabriel Goh, Scott Gray, Chelsea Voss, Alec Radford, Mark Chen, and Ilya Sutskever. Zero-shot text-to-image generation. In Proceedings of the International Conference on Machine Learning (ICML), pages 8821–8831. PMLR, 2021. 3
- [57] Jeremy Reizenstein, Roman Shapovalov, Philipp Henzler, Luca Sbordone, Patrick Labatut, and David Novotny. Common objects in 3d: Large-scale learning and evaluation of real-life 3d category reconstruction. In Proceedings of the IEEE/CVF International Conference on Computer Vision (ICCV), pages 10901–10911, October 2021. 10
- [58] Elad Richardson, Gal Metzer, Yuval Alaluf, Raja Giryes, and Daniel Cohen-Or. Texture: Text-guided texturing of 3d shapes. arXiv preprint arXiv:2302.01721, 2023. 3
- [59] Robin Rombach, Andreas Blattmann, Dominik Lorenz, Patrick Esser, and Bj¨orn Ommer. High-resolution image synthesis with latent diffusion models. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 10684–10695, 2022. 3
- [60] Chitwan Saharia, William Chan, Saurabh Saxena, Lala Li, Jay Whang, Emily L Denton, Kamyar Ghasemipour, Raphael Gontijo Lopes, Burcu Karagol Ayan, Tim Salimans, et al. Photorealistic text-to-image diffusion models with deep language understanding. Advances in Neural Information Processing Systems (NeurIPS), 35:36479–36494, 2022. 3
- [61] Johannes Lutz Sch¨onberger and Jan-Michael Frahm. Structure-from-motion revisited. In Conference on Computer Vision and Pattern Recognition (CVPR), 2016. 2
- [62] Johannes Lutz Sch¨onberger and Jan-Michael Frahm. Structure-from-motion revisited. In Conference on Computer Vision and Pattern Recognition (CVPR), 2016. 5
- [63] Johannes Lutz Sch¨onberger, Enliang Zheng, Marc Pollefeys, and Jan-Michael Frahm. Pixelwise view selection for unstructured multi-view stereo. In European Conference on Computer Vision (ECCV), 2016. 2
- [64] Hoigi Seo, Hayeon Kim, Gwanghyun Kim, and Se Young Chun. Ditto-nerf: Diffusion-based iterative text to omnidirectional 3d model. arXiv preprint arXiv:2304.02827,

2023. 3

- [65] Junyoung Seo, Wooseok Jang, Min-Seop Kwak, Jaehoon Ko, Hyeonsu Kim, Junho Kim, Jin-Hwa Kim, Jiyoung Lee, and Seungryong Kim. Let 2d diffusion model know 3dconsistency for robust text-to-3d generation. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2023. 3
- [66] Andrea Tagliasacchi and Ben Mildenhall. Volume rendering digest (for nerf). arXiv preprint arXiv:2209.02417, 2022. 2
- [67] Jiaxiang Tang. Stable-dreamfusion: Text-to-3d with stable-diffusion, 2022. https://github.com/ashawkey/stabledreamfusion. 3
- [68] Jiaxiang Tang, Jiawei Ren, Hang Zhou, Ziwei Liu, and Gang Zeng. Dreamgaussian: Generative gaussian splatting for efficient 3d content creation. arXiv preprint arXiv:2309.16653,

2023. 3, 9, 10, 32

- [69] Dor Verbin, Peter Hedman, Ben Mildenhall, Todd Zickler, Jonathan T Barron, and Pratul P Srinivasan. Ref-nerf: Structured view-dependent appearance for neural radiance fields. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 5481–5490. IEEE, 2022. 2
- [70] Haochen Wang, Xiaodan Du, Jiahao Li, Raymond A Yeh, and Greg Shakhnarovich. Score jacobian chaining: Lifting pretrained 2d diffusion models for 3d generation. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2023. 3
- [71] Peng Wang, Lingjie Liu, Yuan Liu, Christian Theobalt, Taku Komura, and Wenping Wang. Neus: Learning neural implicit surfaces by volume rendering for multi-view reconstruction. In Advances in Neural Information Processing Systems (NeurIPS), 2021. 2
- [72] Yiqun Wang, Ivan Skorokhodov, and Peter Wonka. Hf-neus: Improved surface reconstruction using high-frequency details. Advances in Neural Information Processing Systems (NeurIPS), 35:1966–1978, 2022. 2
- [73] Olivia Wiles, Georgia Gkioxari, Richard Szeliski, and Justin Johnson. Synsin: End-to-end view synthesis from a single image. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 7467– 7477, 2020. 2
- [74] Qiangeng Xu, Zexiang Xu, Julien Philip, Sai Bi, Zhixin Shu, Kalyan Sunkavalli, and Ulrich Neumann. Point-nerf: Point-based neural radiance fields. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 5438–5448, 2022. 2
- [75] Yao Yao, Zixin Luo, Shiwei Li, Tian Fang, and Long Quan. Mvsnet: Depth inference for unstructured multi-view stereo. In Proceedings of the European Conference on Computer Vision (ECCV), pages 767–783, 2018. 2
- [76] Yao Yao, Zixin Luo, Shiwei Li, Tianwei Shen, Tian Fang, and Long Quan. Recurrent mvsnet for high-resolution multi-view stereo depth inference. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 5525–5534, 2019. 2
- [77] Lior Yariv, Jiatao Gu, Yoni Kasten, and Yaron Lipman. Volume rendering of neural implicit surfaces. Advances in Neural Information Processing Systems (NeurIPS), 34:4805– 4815, 2021. 2
- [78] Lior Yariv, Yoni Kasten, Dror Moran, Meirav Galun, Matan Atzmon, Basri Ronen, and Yaron Lipman. Multiview neural surface reconstruction by disentangling geometry and appearance. Advances in Neural Information Processing Systems (NeurIPS), 33:2492–2502, 2020. 2
- [79] Wang Yifan, Felice Serena, Shihao Wu, Cengiz Oztireli,¨ and Olga Sorkine-Hornung. Differentiable surface splatting for point-based geometry processing. ACM Transactions on Graphics (TOG), 38(6):1–14, 2019. 2
- [80] Alex Yu, Sara Fridovich-Keil, Matthew Tancik, Qinhong Chen, Benjamin Recht, and Angjoo Kanazawa. Plenoxels: Radiance fields without neural networks. arXiv preprint arXiv:2112.05131, 2(3):6, 2021. 2
- [81] Alex Yu, Ruilong Li, Matthew Tancik, Hao Li, Ren Ng, and Angjoo Kanazawa. PlenOctrees for real-time rendering of

- neural radiance fields. In Proceedings of the IEEE/CVF International Conference on Computer Vision (ICCV), 2021. 1
- [82] Alex Yu, Vickie Ye, Matthew Tancik, and Angjoo Kanazawa. pixelnerf: Neural radiance fields from one or few images. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 4578–4587,

2021. 2

- [83] Zehao Yu and Shenghua Gao. Fast-mvsnet: Sparse-todense multi-view stereo with learned propagation and gaussnewton refinement. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 1949–1958, 2020. 2
- [84] Zehao Yu, Songyou Peng, Michael Niemeyer, Torsten Sattler, and Andreas Geiger. Monosdf: Exploring monocular geometric cues for neural implicit surface reconstruction. In Advances in Neural Information Processing Systems (NeurIPS), 2022. 2
- [85] Jason Zhang, Gengshan Yang, Shubham Tulsiani, and Deva Ramanan. Ners: neural reflectance surfaces for sparse-view 3d reconstruction in the wild. Advances in Neural Information Processing Systems (NeurIPS), 34:29835–29847, 2021. 2
- [86] Qiang Zhang, Seung-Hwan Baek, Szymon Rusinkiewicz, and Felix Heide. Differentiable point-based radiance fields for efficient view synthesis. In SIGGRAPH Asia 2022 Conference Papers, pages 1–12, 2022. 2
- [87] Richard Zhang, Phillip Isola, Alexei A Efros, Eli Shechtman, and Oliver Wang. The unreasonable effectiveness of deep features as a perceptual metric. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2018. 32
- [88] Matthias Zwicker, Hanspeter Pfister, Jeroen Van Baar, and Markus Gross. Ewa volume splatting. Proceedings Visualization, 2001. VIS’01., pages 29–538, 2001. 5

#### A. Theory Behind Generalized Exponentials

##### A.1. Generalized Exponential Function

The Generalized Exponential Function (GEF) is similar to the probability density function (PDF) of the Generalized Normal Distribution (GND) [14] with an additional amplitude parameter A ∈ R. This function allows for a more flexible adaptation to various data shapes by adjusting the shape parameter β ∈ (0,∞). The GEF is given by the following.

f(x|µ,α,β,A) = Aexp −

|x − µ| α

β

(10)

where µ ∈ R is the location parameter, α ∈ R is the scale parameter, A defines the amplitude, and β > 0 is the shape parameter. For β = 2, the GEF becomes a scaled Gaussian distribution:

2

x − µ α/√2

- 1

- 2

A α√2π

exp −

f(x|µ,α,β = 2,A) =

(11) And for β = 1, Eq. 10 reduces to a scaled Laplace distribution:

|x − µ| α

A 2α

(12)

f(x|µ,α,β = 1,A) =

exp −

The GEF, therefore, provides a versatile framework for modeling a wide range of data by varying β, unlike the Gaussian mixtures, which have a low-pass frequency domain. Many common signals, like the square or triangle, are band-unlimited, constituting a fundamental challenge to Gaussian-based methods (see Fig.12). In this paper, we try to learn a positive β for every component of the Gaussian splatting to allow for a generalized 3D representation.

##### A.2. Theoretical Results

Despite its generalizable capabilities, the GEF has no fixed behavior in terms of frequency domain. The error functions of the GEF and its Fourier domain cannot be studied analytically, as they involve complex integrals of exponentials without closed form that depend on the shape parameter β. For example, the Fourier of GEF is given by

β

∞

|x − µ| α

e−2πixξ dx

F(f)(ξ) =

Aexp −

−∞

which does not have a closed-form solution for a general β. We demonstrate that for specific cases, such as for a square signal, the GEF can achieve a smaller approximation error than the corresponding Gaussian function by properly choosing β. Theorem 1 provides a theoretical foundation for preferring the GEF over standard Gaussian functions in our GES representation instead of 3D Gaussian Splatting [27].

Theorem 1 (Superiority of GEF Approximation Over Gaussian for Square Wave Signals). Let S(t) represent a square wave signal with amplitude A > 0 and width L > 0 centered at t = 0. Define two functions: a scaled Gaussian G(t;α,A) = Ae−

t2

α2 , and a Generalized Exponential Function GEF(t;α,β,A) = Ae−(|t|/α)

β

. For any given scale parameter α, there exists a shape parameter β such that the approximation error Ef = −∞ ∞ |S(t) − f(t)|dt. of the square signal S(t) using GEF is strictly smaller than that using the Gaussian G.

Proof. The error metric Ef for the square signal S(t) approximation using f function as Ef = −∞ ∞ |S(t)−f(t)|dt. Utilizing symmetry and definition of S(t), and the fact that S(t) > G(t;α,A), the error for the Gaussian approximation simplifies to:

EG = 2

L/2

t2 α2

A(1 − e−

0

)dt + 2

∞

t2 α2

Ae−

dt.

L/2

For the GEF approximation, the error is:

EGEF = 2

L/2

β

A(1−e−(t/α)

0

)dt+2

∞

β

Ae−(t/α)

L/2

dt.

The goal is to show the difference in errors ∆E = EG − EGEF to be strictly positive, by picking β appropriately. The error difference can be described as follows.

∆E = ∆Emiddle + ∆Etail

L/2

L/2

t2 α2

β

A(1−e−

A(1−e−(t/α)

)dt − 2

∆Emiddle = 2

)dt

0

0

∞

∞

t2 α2

β

Ae−

Ae−(t/α)

dt − 2

∆Etail = 2

dt

L/2

L/2

Let us Define err(t) as the difference between the exponential terms:

t2 α2

β

err(t) = e−

− e−(t/α)

.

The difference in the middle error terms for the Gaussian and GEF approximations, ∆Emiddle, can be expressed using err(t) as:

∆Emiddle = 2A

L/2

err(t)dt.

0

Using the trapezoidal approximation of the integral, this simplifies to:

L2 4α2

β

∆Emiddle ≈ LA err(L/2) = LA e−

− e−(L/2α)

.

Based on the fact that the negative exponential is monotonically decreasing and to ensure ∆Emiddle is always positive, we choose β based on the relationship between L/2 and α :

- • If L2 > α (i.e., 2Lα > 1), choosing β > 2 ensures

e−(L/2α)

β

< e−

L2

4α2 .

- • If L2 < α (i.e., 2Lα < 1), choosing 0 < β < 2 results

L2

β

< e−

in e−(L/2α)

4α2 .

Thus, ∆Emiddle can always be made positive by choosing β appropriately, implying that the error in the GEF approximation in the interval [−L/2,L/2] is always less than that of the Gaussian approximation. Similarly, the difference of tail errors ∆Etail can be made positive by an appropriate choice of β, concluding that the total error EGEF is strictly less than EG. This concludes the proof.

| |
|---|

##### A.3. Numerical Simulation of Gradient-Based 1D Mixtures

Objective. The primary objective of this numerical simulation is to evaluate the effectiveness of the generalized exponential model in representing various one-dimensional (1D) signal types. This evaluation was conducted by fitting the model to synthetic signals generated to embody characteristics of square, triangle, parabolic, half sinusoidal, Gaussian, and exponential functions, which can constitute a nonexclusive list of basic topologies available in the real world. Simulation Setup. The experimental framework was based on a series of parametric models implemented in PyTorch, designed to approximate 1D signals using mixtures of different functions such as Gaussian, Difference of Gaussians (DoG), Laplacian of Gaussian (LoG), and a Generalized mixture model. Each model comprised parameters for means, variances (or scales), and weights, with the generalized model incorporating an additional parameter, β, to control the exponentiation of the Gaussian function.

Models. Here, we describe the mixture models used to approximate the true signal forms.

- • Gaussian Mixture Model (GMM): The GMM combines several Gaussian functions, each defined by its

mean (µi), variance (σi2), and weight (wi). For a set of N Gaussian functions, the mixture model g(x) can be expressed as:

g(x) =

N

i=1

wi exp −

(x − µi)2 2σi2 + ϵ

, (13)

where ϵ is a small constant to avoid division by zero, with ϵ = 1e − 8.

- • Difference of Gaussians (DoG) Mixture Model: The DoG mixture model is comprised of elements that represent the difference between two Gaussian functions with a fixed variance ratio ν. The model d(x) for N

components is given by:

N

d(x) =

wiDi

i=1

(x − µi)2 2(σi2/ν) + ϵ

(x − µi)2 2σi2 + ϵ − exp −

Di = exp −

(14) where σi is a scale parameter, and the variance ratio ν is fixed to be 4.

- • Laplacian of Gaussian (LoG) Mixture Model: The LoG mixture model is formed by a series of Laplacian of Gaussian functions, each defined by a mean (µi), scale (γi), and weight (wi). The mixture model l(x) is:

l(x) =

N

i=1

wi −

(x − µi)2 γi2

+ 1 exp −

(x − µi)2 2γi2 + ϵ

,

(15)

- • Generalized Mixture Model: This model generalizes the Gaussian mixture by introducing a shape parameter β. Each component of the model h(x) is expressed as:

,

h(x) =

N

|x − µi|β 2σi2 + ϵ

wi exp −

i=1

, (16)

where β is a learnable parameter that is optimized alongside other parameters. When β = 2 is fixed, the equation in Eq.(16) reduces to the one in Eq.(13).

Model Configuration. The models were configured with a varying number of components N, with tests conducted using N = {2,5,8,10,15,20,50,100}. The weights of the components could be either positive or unrestricted. For the generalized model, the β parameter was learnable.

Training Procedure. Each model was trained using the Adam optimizer with a mean squared error loss function. The input x was a linearly spaced tensor representing the domain of the synthetic signal, and the target y was the value of the signal at each point in x. Training proceeded for a predetermined number of epochs, and the loss was recorded at the end of training.

Data Generation. Synthetic 1D signals were generated for various signal types over a specified range, with a given data size and signal width. The signals were used as the ground truth for training the mixture models. The ground truth signals used in the experiment are one-dimensional (1D) functions that serve as benchmarks for evaluating signal processing algorithms. Each signal type is defined within a specified width around the origin, and the value outside this interval is zero ( see Fig.12). The parameter width σ dictates the effective span of the non-zero portion of the signal. We define six distinct signal types as follows:

Square Signal

Fourier Transform of Square

- 0

- 1

- 0
- 1

Magnitude

Amplitude

| | | | | | | | | | | | | |
|---|---|---|---|---|---|---|---|---|---|---|---|---|
| | | | | | | | | | | | | |

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

Time

Frequency

Triangle Signal

Fourier Transform of Triangle

- 0
- 1

- 0

- 1

Magnitude

Amplitude

| | | | | | | | | | | |
|---|---|---|---|---|---|---|---|---|---|---|
| | | | | | | | | | | |

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

Time

Frequency

Parabolic Signal

Fourier Transform of Parabolic

- 0
- 1

Magnitude

Amplitude

| | | | | | | | | | | |
|---|---|---|---|---|---|---|---|---|---|---|
| | | | | | | | | | | |
| | | | | | | | | | | |

| | | | | | | | | | | |
|---|---|---|---|---|---|---|---|---|---|---|
| | | | | | | | | | | |
| | | | | | | | | | | |

2000

0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

Time

Frequency

Half_sinusoid Signal

Fourier Transform of Half_sinusoid

- 0
- 1

Magnitude

Amplitude

100

| | | | | | | | | | | |
|---|---|---|---|---|---|---|---|---|---|---|
| | | | | | | | | | | |
| | | | | | | | | | | |

0

100

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

Time

Frequency

Exponential Signal

Fourier Transform of Exponential

- 0
- 1

2

Magnitude

Amplitude

| | | | | | | | | | | |
|---|---|---|---|---|---|---|---|---|---|---|
| | | | | | | | | | | |

| | | | | | | | | | | |
|---|---|---|---|---|---|---|---|---|---|---|
| | | | | | | | | | | |
| | | | | | | | | | | |

0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

Time

Frequency

Gaussian Signal

Fourier Transform of Gaussian

- 0
- 1

Magnitude

Amplitude

| | | | | | | | | | | |
|---|---|---|---|---|---|---|---|---|---|---|
| | | | | | | | | | | |
| | | | | | | | | | | |

| | | | | | | | | | | |
|---|---|---|---|---|---|---|---|---|---|---|
| | | | | | | | | | | |
| | | | | | | | | | | |

- 0
- 1

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

Time

Frequency

- Figure 12. Commong Signals Used and Their Fourier Transforms. Note that the Gaussian function is low-pass bandwidth, while common signals like the square and triangle with sharp edges have infinite bandwidth, making them challenging to be fitted with mixtures that have low-pass frequency bandwidth (e.g. Gaussian mixtures, represented by Gaussian Splatting [27]).

- 1. Square Signal: The square signal is a binary function where the value is 1 within the interval (−σ2, σ2) and 0 elsewhere. Mathematically, it is represented as

fsquare(x) =

1 if − σ2 < x < σ2, 0 otherwise.

(17)

Its Fourier Transform is given by

FT{Square Wave}(f) = sinc

f · σ π

(18)

- 2. Triangle Signal: This signal increases linearly from the left edge of the interval to the center and decreases symmetrically to the right edge, forming a triangular shape. It is defined as

ftriangle(x) =

σ 2 − |x| if − σ2 < x < σ2,

0 otherwise.

(19)

Its Fourier Transform is

FT{Triangle Wave}(f) = sinc

f · σ 2π

2

(20)

- 3. Parabolic Signal: This signal forms a downwardfacing parabola within the interval, and its expression is

fparabolic(x) =

(σ2)2 − x2 if − σ2 < x < σ2, 0 otherwise.

(21)

The Fourier Transform of the parabolic signal is

FT{Parabolic Wave}(f) =

3 · sinc f2·πσ

2

π2 · f2

(22)

- 4. Half Sinusoid Signal: A half-cycle of a sine wave is contained within the interval, starting and ending with zero amplitude. Its formula is

###### sin (x + σ2)πσ if − σ2 < x < σ2, 0 otherwise.

fhalf sinusoid(x) =

(23) Its Fourier Transform is described by

FT{Half Sinusoid}(f) =

σ 2 if f = 0 σ·sin(π·f·σ)

π2·f2 otherwise

(24)

- 5. Exponential Signal: Exhibiting an exponential decay centered at the origin, this signal is represented by

fexponential(x) =

exp(−|x|) if − σ2 < x < σ2, 0 otherwise.

(25) The Fourier Transform for the exponential signal is

FT{Exponential}(f) =

σ f2 + σ2 2

(26)

- 6. Gaussian Signal: Unlike the others, the Gaussian signal is not bounded within a specific interval but instead extends over the entire range of x, with its amplitude governed by a Gaussian distribution. It is given by

x2 2σ2

fGaussian(x) = exp −

. (27)

The Fourier Transform of the Gaussian signal is also a Gaussian, which in the context of standard deviation σ is represented as

√

2π·σ·exp −2π2σ2f2 (28)

FT{Gaussian}(f) =

As shown in Fig.12, the Gaussian function has a lowpass band, while signals like the square and triangle with sharp edges have infinite bandwidth, making them challenging for mixtures that have low-pass frequency bandwidth (e.g. Gaussian mixtures, represented by Gaussian Splatting [27]).

Each signal is sampled at discrete points using a PyTorch tensor to facilitate computational manipulation and analysis within the experiment’s framework. We show in Fig.14,15,16,17,18,19,20,21,22,23,24, and 25 examples of fitting all the mixture on all different signal types of interest when positive weighting is used in the mixture vs. when allowing real weighting in the combinations in the above equations. Note how sharp edges constitute a challenge for Gaussians that have low pass bandwidth while a square signal has an infinite bandwidth known by the sinc function [25].

Loss Evaluation. The models’ performance was evaluated based on the loss value after training. Additionally, the model’s ability to represent the input signal was visually inspected through generated plots. Multiple runs per configuration were executed to account for variance in the results.

Stability Evaluation. Model stability and performance were assessed using a series of experiments involving various signal types and mixture models. Each model was trained on a 1D signal generated according to predefined signal types (square, triangle, parabolic, half sinusoid, Gaussian, and exponential), with the goal of minimizing the

mean squared error (MSE) loss between the model output and the ground truth signal. The number of components in the mixture models (N) varied among a set of values, and models were also differentiated based on whether they were constrained to positive weights. For a comprehensive evaluation, each configuration was run multiple times (20 runs per configuration) to account for variability in the training process. During these runs, the number of instances where the training resulted in a NaN loss was recorded as an indicator of stability issues. The stability of each model was quantified by the percentage of successful training runs (Total Runs−NaN Loss Counts

Total Runs × 100%). The experiments that failed failed because the loss has diverged to NaN. This typical numerical instability in optimization is the result of learning the variance which can go close to zero, resulting in the exponential formula (in Eq.(10)) to divide by an extremely small number.

The average MSE loss from successful runs was calculated to provide a measure of model performance. The results of these experiments were plotted, showing the relationship between the number of components and the stability and loss of the models for each signal type.

Simulation Results. In the conducted analysis, both the loss and stability of various mixture models with positive and non-positive weights were evaluated on signals with different shapes. As depicted in Figure 13, the Gaussian Mixture Model with positive weights consistently yielded the lowest loss across the number of components, indicating its effective approximation of the square signal. Conversely, non-positive weights in the Gaussian and General models showed a higher loss, emphasizing the importance of weight sign-on model performance. These findings highlight the intricate balance between model complexity and weight constraints in achieving both low loss and high stability. Note that GEF is very efficient in fitting the square with few components, while LoG and DoG are more stable for a larger number of components. Also, note that positive weight mixtures tend to achieve lower loss with a smaller number of components but are less stable for a larger number of components.

|0 20 40 60 80 100<br><br>Number of Components (N)<br><br>10 4<br><br>10 3<br><br>10 2<br><br>10 1<br><br>AverageLoss(logscale)<br><br>Loss Value vs Number of Components on square signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>0 20 40 60 80 100<br><br>Number of Components (N)<br><br>0<br><br>20<br><br>40<br><br>60<br><br>80<br><br>100<br><br>Stability(%)<br><br>Stability vs Number of Components on square signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>(a) Square signal<br><br>|0 20 40 60 80 100<br><br>Number of Components (N)<br><br>10 4<br><br>10 3<br><br>10 2<br><br>10 1<br><br>100<br><br>AverageLoss(logscale)<br><br>Loss Value vs Number of Components on parabolic signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>0 20 40 60 80 100<br><br>Number of Components (N)<br><br>0<br><br>20<br><br>40<br><br>60<br><br>80<br><br>100<br><br>Stability(%)<br><br>Stability vs Number of Components on parabolic signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>(b) Parabolic signal|
|---|---|
|0 20 40 60 80 100<br><br>Number of Components (N)<br><br>10 4<br><br>10 3<br><br>10 2<br><br>AverageLoss(logscale)<br><br>Loss Value vs Number of Components on exponential signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>0 20 40 60 80 100<br><br>Number of Components (N)<br><br>0<br><br>20<br><br>40<br><br>60<br><br>80<br><br>100<br><br>Stability(%)<br><br>Stability vs Number of Components on exponential signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>(c) Exponential signal|0 20 40 60 80 100<br><br>Number of Components (N)<br><br>10 5<br><br>10 4<br><br>10 3<br><br>10 2<br><br>10 1<br><br>AverageLoss(logscale)<br><br>Loss Value vs Number of Components on triangle signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>0 20 40 60 80 100<br><br>Number of Components (N)<br><br>0<br><br>20<br><br>40<br><br>60<br><br>80<br><br>100<br><br>Stability(%)<br><br>Stability vs Number of Components on triangle signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>(d) Triangle signal|
|0 20 40 60 80 100<br><br>Number of Components (N)<br><br>10 7<br><br>10 6<br><br>10 5<br><br>10 4<br><br>10 3<br><br>10 2<br><br>AverageLoss(logscale)<br><br>Loss Value vs Number of Components on gaussian signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>0 20 40 60 80 100<br><br>Number of Components (N)<br><br>0<br><br>20<br><br>40<br><br>60<br><br>80<br><br>100<br><br>Stability(%)<br><br>Stability vs Number of Components on gaussian signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>(e) Gaussian signal<br><br>|0 20 40 60 80 100<br><br>Number of Components (N)<br><br>10 5<br><br>10 4<br><br>10 3<br><br>10 2<br><br>AverageLoss(logscale)<br><br>Loss Value vs Number of Components on half_sinusoid signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>0 20 40 60 80 100<br><br>Number of Components (N)<br><br>0<br><br>20<br><br>40<br><br>60<br><br>80<br><br>100<br><br>Stability(%)<br><br>Stability vs Number of Components on half_sinusoid signal<br><br>Gaussian (Positive)<br><br>Gaussian (Real)<br><br>DoG (Positive)<br><br>DoG (Real)<br><br>LoG (Positive)<br><br>LoG (Real)<br><br>GEF (Positive)<br><br>GEF (Real)<br><br>(f) Half sinusoid signal|

###### Figure 13. Numerical Simulation Results of Different Mixtures. We show a comparison of average loss and stability (percentage of successful runs) for different mixture models optimized with gradient-based optimizers across varying numbers of components and weight configurations (positive vs. real weights) on various signal types (a-f).

Overfitting DoG Mixture to a square Function, N=2, loss=1.73

Overfitting LoG Mixture to a square Function, N=2, loss=8.06

Overfitting General Mixture to a square Function, N=2, loss=0.44

Overfitting Gaussian Mixture to a square Function, N=2, loss=1.82

1.2

True square

1.0

True square LoG Mixture

True square

True square

1.0

DoG Mixture

GEF Mixture

Gaussian Mixture

1.0

1.0

0.8

0.8

0.8

0.6

0.8

0.6

0.4

0.6

0.6

y

y

y

y

0.2

0.4

0.4

0.4

0.0

0.2

0.2

0.2

0.2

0.0

0.0

0.0

0.4

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a square Function, N=5, loss=0.86

Overfitting LoG Mixture to a square Function, N=5, loss=1.45

Overfitting General Mixture to a square Function, N=5, loss=0.09

Overfitting Gaussian Mixture to a square Function, N=5, loss=0.48

True square

True square LoG Mixture

True square

True square

1.0

DoG Mixture

1.0

1.0

GEF Mixture

Gaussian Mixture

1.0

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.4

0.4

0.2

0.4

0.0

0.2

0.2

0.2

0.2

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a square Function, N=8, loss=0.29

Overfitting LoG Mixture to a square Function, N=8, loss=0.92

Overfitting General Mixture to a square Function, N=8, loss=nan

Overfitting Gaussian Mixture to a square Function, N=8, loss=nan

True square

1.0

True square LoG Mixture

True square

1.0

True square

1.5

DoG Mixture

GEF Mixture

Gaussian Mixture

1.0

0.8

0.8

1.0

0.8

0.6

0.6

0.6

0.5

y

y

y

y

0.4

0.4

0.4

0.0

0.2

0.2

0.2

0.5

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a square Function, N=10, loss=0.26

Overfitting LoG Mixture to a square Function, N=10, loss=0.87

Overfitting General Mixture to a square Function, N=10, loss=nan

Overfitting Gaussian Mixture to a square Function, N=10, loss=nan

True square

1.0

True square LoG Mixture

True square

1.0

True square

DoG Mixture

GEF Mixture

1.0

Gaussian Mixture

1.5

0.8

0.8

0.8

1.0

0.6

0.6

0.6

0.5

y

y

y

y

0.4

0.4

0.4

0.0

0.2

0.2

0.2

0.5

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a square Function, N=20, loss=0.03

Overfitting General Mixture to a square Function, N=20, loss=nan

Overfitting Gaussian Mixture to a square Function, N=20, loss=nan

Overfitting LoG Mixture to a square Function, N=20, loss=0.39

True square

1.0

True square

1.0

True square

True square LoG Mixture

1.0

DoG Mixture

1.25

GEF Mixture

Gaussian Mixture

0.8

1.00

0.8

0.8

0.75

0.6

0.6

0.6

0.50

y

y

y

y

0.25

0.4

0.4

0.4

0.00

0.2

0.2

0.2

0.25

0.50

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 14. Numerical Simulation Examples of Fitting Squares with Positive Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for Square signals with positive weights mixtures. The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the Square with few components while LoG and DoG are more stable for a larger number of components.

Overfitting LoG Mixture to a square Function, N=2, loss=8.06

Overfitting General Mixture to a square Function, N=2, loss=0.83

Overfitting Gaussian Mixture to a square Function, N=2, loss=1.91

Overfitting DoG Mixture to a square Function, N=2, loss=6.39

8

1.0

True square LoG Mixture

True square

True square

6

True square

1.25

GEF Mixture

Gaussian Mixture

DoG Mixture

6

0.8

4

1.00

4

0.6

0.75

2

2

0.4

0.50

y

y

y

y

0

0

0.2

0.25

2

2

0.0

0.00

4

0.2

4

0.25

6

0.4

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a square Function, N=5, loss=0.86

Overfitting LoG Mixture to a square Function, N=5, loss=1.12

Overfitting General Mixture to a square Function, N=5, loss=0.16

Overfitting Gaussian Mixture to a square Function, N=5, loss=0.57

6

8

True square

True square LoG Mixture

True square

True square

1.0

DoG Mixture

1.0

GEF Mixture

Gaussian Mixture

6

4

0.5

0.8

4

2

2

0.6

0.0

y

y

y

y

0

0

0.4

0.5

2

2

0.2

4

1.0

4

0.0

6

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a square Function, N=8, loss=0.87

Overfitting DoG Mixture to a square Function, N=8, loss=0.94

Overfitting General Mixture to a square Function, N=8, loss=0.10

Overfitting Gaussian Mixture to a square Function, N=8, loss=0.24

- 0

- 1

- 2

- 3

- 4

- 5

- 6

True square LoG Mixture

True square

True square

- 0

- 1

- 2

- 3

True square

DoG Mixture

4

- 0

- 1

- 2

- 3

GEF Mixture

Gaussian Mixture

2

0

y

y

y

y

2

1

4

1

1

2

6

2

2

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a square Function, N=10, loss=0.40

Overfitting DoG Mixture to a square Function, N=10, loss=0.20

Overfitting General Mixture to a square Function, N=10, loss=0.09

Overfitting Gaussian Mixture to a square Function, N=10, loss=nan

True square LoG Mixture

True square

1.0

True square

True square

- 0

- 1

- 2

- 0

- 1

- 2

- 3

DoG Mixture

GEF Mixture

1.5

Gaussian Mixture

0.8

1.0

0.6

0.5

y

y

y

y

0.0

0.4

1

0.5

1

0.2

1.0

2

2

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a square Function, N=20, loss=0.12

Overfitting DoG Mixture to a square Function, N=20, loss=0.01

Overfitting General Mixture to a square Function, N=20, loss=nan

Overfitting Gaussian Mixture to a square Function, N=20, loss=nan

True square LoG Mixture

1.0

1.5

True square

True square

1.0

True square

- 0

- 1

- 2

- 3

DoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

1.0

0.6

0.6

0.5

y

y

y

y

0.4

0.4

0.0

1

0.2

0.2

0.5

2

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 15. Numerical Simulation Examples of Fitting Squares with Real Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for Square signals with Real weights mixtures (can be negative). The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the Square with few components while LoG and DoG are more stable for a larger number of components.

Overfitting DoG Mixture to a parabolic Function, N=2, loss=37.52

Overfitting LoG Mixture to a parabolic Function, N=2, loss=13.26

Overfitting General Mixture to a parabolic Function, N=2, loss=2.95

Overfitting Gaussian Mixture to a parabolic Function, N=2, loss=18.75

10

True parabolic

10

True parabolic

True parabolic

True parabolic

DoG Mixture

LoG Mixture

GEF Mixture

8

8

Gaussian Mixture

8

8

6

6

6

6

4

y

y

y

y

4

4

4

2

0

2

2

2

2

0

0

0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a parabolic Function, N=5, loss=1.25

Overfitting LoG Mixture to a parabolic Function, N=5, loss=6.95

Overfitting General Mixture to a parabolic Function, N=5, loss=0.08

Overfitting Gaussian Mixture to a parabolic Function, N=5, loss=1.98

True parabolic

True parabolic

True parabolic

True parabolic

DoG Mixture

LoG Mixture

8

GEF Mixture

8

Gaussian Mixture

8

8

6

6

6

6

4

y

y

y

y

4

2

4

4

0

2

2

2

2

0

0

0

4

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a parabolic Function, N=8, loss=0.83

Overfitting LoG Mixture to a parabolic Function, N=8, loss=1.55

Overfitting General Mixture to a parabolic Function, N=8, loss=0.03

Overfitting Gaussian Mixture to a parabolic Function, N=8, loss=0.14

True parabolic

True parabolic

True parabolic

True parabolic

DoG Mixture

LoG Mixture

8

GEF Mixture

8

Gaussian Mixture

8

8

6

6

6

6

4

y

y

y

y

4

4

4

2

2

2

2

0

2

0

0

0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a parabolic Function, N=10, loss=0.42

Overfitting LoG Mixture to a parabolic Function, N=10, loss=0.42

Overfitting General Mixture to a parabolic Function, N=10, loss=0.02

Overfitting Gaussian Mixture to a parabolic Function, N=10, loss=0.08

True parabolic

True parabolic

True parabolic

True parabolic

DoG Mixture

LoG Mixture

8

GEF Mixture

8

Gaussian Mixture

8

8

6

6

6

6

4

y

y

y

y

4

4

4

2

2

2

2

0

0

2

0

0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

y Overfitting DoG Mixture to a parabolic Function, N=20, loss=0.05

Overfitting LoG Mixture to a parabolic Function, N=20, loss=0.41

Overfitting General Mixture to a parabolic Function, N=20, loss=0.01

Overfitting Gaussian Mixture to a parabolic Function, N=20, loss=0.02

True parabolic

True parabolic

True parabolic

True parabolic

DoG Mixture

LoG Mixture

8

8

GEF Mixture

Gaussian Mixture

8

8

6

6

6

6

4

y

y

y

4

4

4

2

2

2

2

0

2

0

0

0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 16. Numerical Simulation Examples of Fitting parabolics with Positive Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for parabolic signals with positive weights mixtures. The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the parabolic with few components while LoG and DoG are more stable for a larger number of components.

Overfitting General Mixture to a parabolic Function, N=2, loss=nan

Overfitting LoG Mixture to a parabolic Function, N=2, loss=13.26

Overfitting Gaussian Mixture to a parabolic Function, N=2, loss=nan

Overfitting DoG Mixture to a parabolic Function, N=2, loss=289.49

10

True parabolic

True parabolic

True parabolic

True parabolic

10

GEF Mixture

LoG Mixture

Gaussian Mixture

DoG Mixture

8

8

8

8

6

6

6

6

4

4

y

y

y

y

4

4

2

2

0

2

0

2

2

2

0

0

4

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a parabolic Function, N=5, loss=1.99

Overfitting General Mixture to a parabolic Function, N=5, loss=nan

Overfitting Gaussian Mixture to a parabolic Function, N=5, loss=nan

Overfitting LoG Mixture to a parabolic Function, N=5, loss=1.23

True parabolic

True parabolic

True parabolic

True parabolic

10.0

DoG Mixture

GEF Mixture

Gaussian Mixture

8

LoG Mixture

8

8

7.5

5.0

6

6

6

2.5

y

y

y

y

4

4

4

0.0

2.5

2

2

2

5.0

0

0

0

7.5

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a parabolic Function, N=8, loss=0.86

Overfitting LoG Mixture to a parabolic Function, N=8, loss=0.68

Overfitting General Mixture to a parabolic Function, N=8, loss=0.02

Overfitting Gaussian Mixture to a parabolic Function, N=8, loss=nan

True parabolic

True parabolic

True parabolic

True parabolic

DoG Mixture

LoG Mixture

8

8

GEF Mixture

Gaussian Mixture

8

8

6

6

6

6

4

4

y

y

4

y

y

4

2

2

2

0

2

0

2

0

0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a parabolic Function, N=10, loss=0.37

Overfitting General Mixture to a parabolic Function, N=10, loss=0.01

Overfitting Gaussian Mixture to a parabolic Function, N=10, loss=0.02

Overfitting LoG Mixture to a parabolic Function, N=10, loss=1.20

True parabolic

10.0

True parabolic

True parabolic

True parabolic

DoG Mixture

8

GEF Mixture

Gaussian Mixture

8

LoG Mixture

7.5

8

5.0

6

6

6

2.5

0.0

y

4

y

4

4

y

y

2.5

2

2

2

5.0

7.5

0

0

0

10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

y Overfitting DoG Mixture to a parabolic Function, N=20, loss=0.08

Overfitting LoG Mixture to a parabolic Function, N=20, loss=0.02

Overfitting Gaussian Mixture to a parabolic Function, N=20, loss=nan

Overfitting General Mixture to a parabolic Function, N=20, loss=0.01

True parabolic

True parabolic

True parabolic

True parabolic

DoG Mixture

LoG Mixture

8

8

Gaussian Mixture

GEF Mixture

8

8

6

6

6

6

4

4

4

y

y

y

4

2

2

2

2

0

0

0

2

0

2

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 17. Numerical Simulation Examples of Fitting Parabolics with Real Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for parabolic signals with Real weights mixtures (can be negative). The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the parabolic with few components while LoG and DoG are more stable for a larger number of components.

Overfitting DoG Mixture to a exponential Function, N=2, loss=1.68

Overfitting LoG Mixture to a exponential Function, N=2, loss=0.35

Overfitting General Mixture to a exponential Function, N=2, loss=nan

Overfitting Gaussian Mixture to a exponential Function, N=2, loss=0.01

1.0

True exponential

1.0

1.0

True exponential

1.0

True exponential

True exponential

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.4

0.4

0.4

0.2

0.2

0.2

0.2

0.0

0.0

0.2

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a exponential Function, N=5, loss=0.02

Overfitting DoG Mixture to a exponential Function, N=5, loss=0.10

Overfitting General Mixture to a exponential Function, N=5, loss=nan

Overfitting Gaussian Mixture to a exponential Function, N=5, loss=nan

1.0

1.0

True exponential

True exponential

1.0

1.0

True exponential

True exponential

LoG Mixture

DoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

y

y

0.4

y

y

0.4

0.4

0.4

0.2

0.2

0.2

0.2

0.0

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a exponential Function, N=8, loss=0.02

Overfitting LoG Mixture to a exponential Function, N=8, loss=0.01

Overfitting General Mixture to a exponential Function, N=8, loss=nan

Overfitting Gaussian Mixture to a exponential Function, N=8, loss=nan

1.0

True exponential

1.0

1.0

1.0

True exponential

True exponential

True exponential

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

y

0.4

y

y

y

0.4

0.4

0.4

0.2

0.2

0.2

0.2

0.0

0.0

0.0

0.0

0.2

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a exponential Function, N=10, loss=0.00

Overfitting LoG Mixture to a exponential Function, N=10, loss=0.00

Overfitting General Mixture to a exponential Function, N=10, loss=nan

Overfitting Gaussian Mixture to a exponential Function, N=10, loss=nan

1.0

True exponential

1.0

1.0

1.0

True exponential

True exponential

True exponential

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.4

0.4

0.4

0.2

0.0

0.2

0.2

0.2

0.2

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a exponential Function, N=20, loss=0.00

Overfitting LoG Mixture to a exponential Function, N=20, loss=0.00

Overfitting General Mixture to a exponential Function, N=20, loss=nan

Overfitting Gaussian Mixture to a exponential Function, N=20, loss=nan

1.0

True exponential

1.0

1.0

True exponential

True exponential

True exponential

1.0

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.2

0.4

0.4

0.4

0.0

0.2

0.2

0.2

0.2

0.4

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 18. Numerical Simulation Examples of Fitting Exponentials with Positive Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for exponential signals with positive weight mixtures. The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the exponential with few components while LoG and DoG are more stable for a larger number of components.

Overfitting LoG Mixture to a exponential Function, N=2, loss=1.39

Overfitting Gaussian Mixture to a exponential Function, N=2, loss=nan

Overfitting DoG Mixture to a exponential Function, N=2, loss=1.01

Overfitting General Mixture to a exponential Function, N=2, loss=0.01

1.0

1.0

True exponential

1.00

True exponential

True exponential

True exponential

1.25

LoG Mixture

Gaussian Mixture

DoG Mixture

GEF Mixture

0.8

0.75

1.00

0.8

0.75

0.6

0.50

0.6

0.50

0.25

0.4

y

y

y

0.25

y

0.00

0.4

0.2

0.00

0.25

0.0

0.25

0.2

0.50

0.50

0.2

0.0

0.75

0.75

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a exponential Function, N=5, loss=0.04

Overfitting Gaussian Mixture to a exponential Function, N=5, loss=nan

Overfitting LoG Mixture to a exponential Function, N=5, loss=0.02

Overfitting General Mixture to a exponential Function, N=5, loss=0.00

1.0

1.0

True exponential

True exponential

True exponential

1.00

True exponential

DoG Mixture

Gaussian Mixture

LoG Mixture

GEF Mixture

0.8

1.0

0.75

0.8

0.6

0.50

0.5

0.6

0.4

0.25

0.0

y

y

y

y

0.2

0.4

0.00

0.5

0.0

0.25

0.2

0.2

1.0

0.50

0.0

0.4

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a exponential Function, N=8, loss=0.01

Overfitting DoG Mixture to a exponential Function, N=8, loss=0.01

Overfitting General Mixture to a exponential Function, N=8, loss=0.00

Overfitting Gaussian Mixture to a exponential Function, N=8, loss=0.01

1.5

True exponential

True exponential

True exponential

True exponential

2.5

LoG Mixture

DoG Mixture

1.0

1.0

GEF Mixture

Gaussian Mixture

1.0

2.0

0.5

0.5

0.5

1.5

0.0

1.0

0.0

0.0

y

y

y

y

0.5

0.5

0.5

0.5

0.0

1.0

1.0

0.5

1.0

1.5

1.0

1.5

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a exponential Function, N=10, loss=0.00

Overfitting DoG Mixture to a exponential Function, N=10, loss=0.00

Overfitting General Mixture to a exponential Function, N=10, loss=0.00

Overfitting Gaussian Mixture to a exponential Function, N=10, loss=0.00

1.5

True exponential

1.00

True exponential

1.0

1.5

True exponential

LoG Mixture

DoG Mixture

Gaussian Mixture

1.0

0.75

1.0

0.5

0.50

0.5

0.5

0.25

0.0

y

0.0

y

y

y

0.00

0.0

0.5

0.25

0.5

0.5

1.0

0.50

1.0

True exponential

0.75

1.0

GEF Mixture

1.5

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a exponential Function, N=20, loss=0.00

Overfitting DoG Mixture to a exponential Function, N=20, loss=0.00

Overfitting General Mixture to a exponential Function, N=20, loss=0.00

Overfitting Gaussian Mixture to a exponential Function, N=20, loss=0.01

2.0

True exponential

True exponential

1.5

True exponential

True exponential

1.0

1.5

LoG Mixture

DoG Mixture

GEF Mixture

1.5

Gaussian Mixture

1.0

1.0

1.0

0.5

0.5

0.5

0.5

0.0

y

0.0

0.0

y

y

y

0.0

0.5

0.5

1.0

0.5

0.5

1.0

1.5

1.0

1.5

2.0

1.0

1.5

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 19. Numerical Simulation Examples of Fitting Exponentials with Real Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for exponential signals with Real weights mixtures (can be negative). The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the exponential with few components while LoG and DoG are more stable for a larger number of components.

Overfitting DoG Mixture to a triangle Function, N=2, loss=4.43

Overfitting LoG Mixture to a triangle Function, N=2, loss=0.90

Overfitting General Mixture to a triangle Function, N=2, loss=0.05

Overfitting Gaussian Mixture to a triangle Function, N=2, loss=0.34

3.0

True triangle DoG Mixture

3.0

3.0

True triangle

3.0

True triangle

True triangle

LoG Mixture

GEF Mixture

Gaussian Mixture

2.5

2.5

2.5

2.5

2.0

2.0

2.0

2.0

1.5

1.5

1.5

y

1.5

y

y

1.0

y

1.0

0.5

1.0

1.0

0.0

0.5

0.5

0.5

0.5

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a triangle Function, N=5, loss=0.06

Overfitting LoG Mixture to a triangle Function, N=5, loss=0.27

Overfitting General Mixture to a triangle Function, N=5, loss=0.00

Overfitting Gaussian Mixture to a triangle Function, N=5, loss=0.02

3.0

True triangle DoG Mixture

3.0

3.0

True triangle

3.0

True triangle

True triangle

LoG Mixture

GEF Mixture

Gaussian Mixture

2.5

2.5

2.5

2.5

2.0

2.0

2.0

2.0

1.5

1.5

1.5

y

1.5

y

y

y

1.0

1.0

1.0

1.0

0.5

0.0

0.5

0.5

0.5

0.5

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a triangle Function, N=8, loss=0.01

Overfitting LoG Mixture to a triangle Function, N=8, loss=0.05

Overfitting General Mixture to a triangle Function, N=8, loss=0.00

Overfitting Gaussian Mixture to a triangle Function, N=8, loss=0.01

3.0

True triangle DoG Mixture

3.0

3.0

True triangle

3.0

True triangle

True triangle

LoG Mixture

GEF Mixture

Gaussian Mixture

2.5

2.5

2.5

2.5

2.0

2.0

2.0

2.0

1.5

1.5

1.5

y

1.5

y

y

y

1.0

1.0

1.0

1.0

0.5

0.5

0.5

0.0

0.5

0.5

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a triangle Function, N=10, loss=0.01

Overfitting LoG Mixture to a triangle Function, N=10, loss=0.04

Overfitting General Mixture to a triangle Function, N=10, loss=0.00

Overfitting Gaussian Mixture to a triangle Function, N=10, loss=0.01

3.0

True triangle DoG Mixture

3.0

3.0

True triangle

3.0

True triangle

True triangle

LoG Mixture

GEF Mixture

Gaussian Mixture

2.5

2.5

2.5

2.5

2.0

2.0

2.0

2.0

1.5

1.5

1.5

y

1.5

y

y

y

1.0

1.0

1.0

1.0

0.5

0.5

0.0

0.5

0.5

0.5

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a triangle Function, N=20, loss=0.00

Overfitting LoG Mixture to a triangle Function, N=20, loss=0.01

Overfitting General Mixture to a triangle Function, N=20, loss=nan

Overfitting Gaussian Mixture to a triangle Function, N=20, loss=nan

3.0

True triangle DoG Mixture

3.0

3.0

True triangle

3.0

True triangle

True triangle

LoG Mixture

GEF Mixture

Gaussian Mixture

2.5

2.5

2.5

2.5

2.0

2.0

2.0

2.0

1.5

1.5

1.5

1.5

y

y

y

y

1.0

1.0

0.5

1.0

1.0

0.0

0.5

0.5

0.5

0.5

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 20. Numerical Simulation Examples of Fitting Triangles with Positive Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for triangle signals with positive weight mixtures. The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the triangle with few components while LoG and DoG are more stable for a larger number of components.

Overfitting DoG Mixture to a triangle Function, N=2, loss=89.91

Overfitting LoG Mixture to a triangle Function, N=2, loss=0.90

Overfitting General Mixture to a triangle Function, N=2, loss=nan

Overfitting Gaussian Mixture to a triangle Function, N=2, loss=nan

3.0

3.0

True triangle DoG Mixture

3.0

True triangle

3.0

True triangle

True triangle

LoG Mixture

GEF Mixture

Gaussian Mixture

2.5

2.5

2.5

2.5

2.0

2.0

2.0

2.0

1.5

1.5

1.5

1.5

y

y

y

1.0

y

1.0

0.5

1.0

1.0

0.0

0.5

0.5

0.5

0.5

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a triangle Function, N=5, loss=3.52

Overfitting DoG Mixture to a triangle Function, N=5, loss=0.03

Overfitting Gaussian Mixture to a triangle Function, N=5, loss=0.04

Overfitting General Mixture to a triangle Function, N=5, loss=0.01

- 0

- 1

- 2

- 3

- 0

- 1

- 2

- 3

True triangle

True triangle DoG Mixture

True triangle

3.0

True triangle

LoG Mixture

- 0

- 1

- 2

- 3

Gaussian Mixture

GEF Mixture

2.5

2.0

1.5

y

y

y

y

1.0

0.5

1

1

0.0

1

0.5

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a triangle Function, N=8, loss=0.27

Overfitting DoG Mixture to a triangle Function, N=8, loss=0.35

Overfitting General Mixture to a triangle Function, N=8, loss=0.00

Overfitting Gaussian Mixture to a triangle Function, N=8, loss=0.00

- 0

- 1

- 2

- 3

True triangle

3.0

True triangle DoG Mixture

3.0

3.0

True triangle

True triangle

LoG Mixture

GEF Mixture

Gaussian Mixture

2.5

2.5

2.5

2.0

2.0

2.0

1.5

1.5

1.5

y

1.0

y

y

y

1.0

1.0

0.5

0.5

0.5

0.0

0.0

1

0.0

0.5

0.5

1.0

0.5

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a triangle Function, N=10, loss=0.27

Overfitting DoG Mixture to a triangle Function, N=10, loss=0.01

Overfitting General Mixture to a triangle Function, N=10, loss=0.00

Overfitting Gaussian Mixture to a triangle Function, N=10, loss=0.05

- 0

- 1

- 2

- 3

True triangle

3.0

- 0

- 1

- 2

- 3

True triangle DoG Mixture

- 0

- 1

- 2

- 3

True triangle

True triangle

LoG Mixture

GEF Mixture

Gaussian Mixture

2.5

2.0

1.5

y

y

y

y

1.0

0.5

0.0

1

1

0.5

1

2

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a triangle Function, N=20, loss=0.01

Overfitting DoG Mixture to a triangle Function, N=20, loss=0.00

Overfitting General Mixture to a triangle Function, N=20, loss=0.00

Overfitting Gaussian Mixture to a triangle Function, N=20, loss=0.00

- 0

- 1

- 2

- 3

True triangle

3.0

- 0

- 1

- 2

- 3

True triangle DoG Mixture

- 0

- 1

- 2

- 3

True triangle

True triangle

LoG Mixture

GEF Mixture

Gaussian Mixture

2.5

2.0

1.5

y

y

y

y

1.0

0.5

0.0

1

0.5

1

1

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 21. Numerical Simulation Examples of Fitting Triangles with Real Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for triangle signals with Real weights mixtures (can be negative). The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the triangle with few components while LoG and DoG are more stable for a larger number of components.

Overfitting DoG Mixture to a gaussian Function, N=2, loss=0.92

Overfitting LoG Mixture to a gaussian Function, N=2, loss=0.02

Overfitting General Mixture to a gaussian Function, N=2, loss=0.00

Overfitting Gaussian Mixture to a gaussian Function, N=2, loss=0.00

1.0

True gaussian

1.0

True gaussian

1.0

True gaussian

1.0

True gaussian

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.4

0.4

0.4

0.2

0.2

0.0

0.2

0.2

0.2

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a gaussian Function, N=5, loss=0.01

Overfitting LoG Mixture to a gaussian Function, N=5, loss=0.00

Overfitting General Mixture to a gaussian Function, N=5, loss=0.00

Overfitting Gaussian Mixture to a gaussian Function, N=5, loss=0.00

True gaussian

1.0

1.0

True gaussian

1.0

True gaussian

1.0

True gaussian

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.4

0.4

0.4

0.2

0.2

0.2

0.2

0.0

0.2

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a gaussian Function, N=8, loss=0.00

Overfitting LoG Mixture to a gaussian Function, N=8, loss=0.00

Overfitting General Mixture to a gaussian Function, N=8, loss=nan

Overfitting Gaussian Mixture to a gaussian Function, N=8, loss=nan

1.0

True gaussian

1.0

1.0

True gaussian

True gaussian

1.0

True gaussian

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.4

0.4

0.4

0.2

0.2

0.0

0.2

0.2

0.2

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a gaussian Function, N=10, loss=0.00

Overfitting LoG Mixture to a gaussian Function, N=10, loss=0.00

Overfitting General Mixture to a gaussian Function, N=10, loss=nan

Overfitting Gaussian Mixture to a gaussian Function, N=10, loss=nan

1.0

True gaussian

1.0

1.0

True gaussian

True gaussian

1.0

True gaussian

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.4

0.2

0.4

0.4

0.0

0.2

0.2

0.2

0.2

0.0

0.0

0.0

0.4

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a gaussian Function, N=20, loss=0.00

Overfitting LoG Mixture to a gaussian Function, N=20, loss=0.00

Overfitting General Mixture to a gaussian Function, N=20, loss=nan

Overfitting Gaussian Mixture to a gaussian Function, N=20, loss=nan

1.0

True gaussian

1.0

1.5

True gaussian

True gaussian

1.0

True gaussian

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

1.0

0.6

0.6

0.6

0.5

y

y

y

y

0.4

0.4

0.4

0.0

0.2

0.2

0.2

0.5

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 22. Numerical Simulation Examples of Fitting Gaussians with Positive Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for Gaussian signals with positive weight mixtures. The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the Gaussian with few components while LoG and DoG are more stable for a larger number of components.

Overfitting LoG Mixture to a gaussian Function, N=2, loss=3.28

Overfitting DoG Mixture to a gaussian Function, N=2, loss=4.55

Overfitting General Mixture to a gaussian Function, N=2, loss=0.00

Overfitting Gaussian Mixture to a gaussian Function, N=2, loss=0.00

1.2

1.0

True gaussian

1.0

True gaussian

True gaussian

1.0

True gaussian

LoG Mixture

DoG Mixture

GEF Mixture

Gaussian Mixture

1.0

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

0.4

y

y

y

y

0.4

0.2

0.4

0.2

0.0

0.0

0.2

0.2

0.2

0.2

0.4

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a gaussian Function, N=5, loss=0.00

Overfitting DoG Mixture to a gaussian Function, N=5, loss=0.28

Overfitting Gaussian Mixture to a gaussian Function, N=5, loss=0.00

Overfitting General Mixture to a gaussian Function, N=5, loss=0.00

True gaussian

True gaussian

1.0

1.25

- 0

- 1

- 2

True gaussian

LoG Mixture

True gaussian

1.0

DoG Mixture

Gaussian Mixture

GEF Mixture

1.00

0.8

0.8

0.75

0.6

0.6

0.50

0.4

0.4

y

y

0.25

0.2

y

0.2

y

0.00

0.0

0.0

0.25

0.2

1

0.2

0.50

0.4

0.4

0.75

0.6

2

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a gaussian Function, N=8, loss=0.00

Overfitting DoG Mixture to a gaussian Function, N=8, loss=0.00

Overfitting General Mixture to a gaussian Function, N=8, loss=0.00

Overfitting Gaussian Mixture to a gaussian Function, N=8, loss=0.00

1.5

1.0

True gaussian

True gaussian

True gaussian

True gaussian

LoG Mixture

DoG Mixture

1.0

1.0

GEF Mixture

Gaussian Mixture

0.8

1.0

0.5

0.5

0.6

0.0

0.5

0.0

y

0.4

y

y

y

0.5

0.0

0.5

0.2

1.0

1.0

0.5

0.0

1.5

2.0

0.2

1.5

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a gaussian Function, N=10, loss=0.00

Overfitting DoG Mixture to a gaussian Function, N=10, loss=0.00

Overfitting Gaussian Mixture to a gaussian Function, N=10, loss=0.00

Overfitting General Mixture to a gaussian Function, N=10, loss=0.00

True gaussian

1.0

True gaussian

True gaussian

True gaussian

LoG Mixture

2.0

DoG Mixture

- 0

- 1

- 2

Gaussian Mixture

GEF Mixture

0.8

- 0

- 1

1.5

0.6

1.0

0.4

0.5

y

0.2

y

y

y

0.0

0.0

1

0.5

0.2

1

1.0

0.4

2

1.5

2

0.6

2.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a gaussian Function, N=20, loss=0.00

Overfitting DoG Mixture to a gaussian Function, N=20, loss=0.00

Overfitting General Mixture to a gaussian Function, N=20, loss=0.00

Overfitting Gaussian Mixture to a gaussian Function, N=20, loss=0.00

1.5

True gaussian

True gaussian

True gaussian

1.0

True gaussian

1.0

LoG Mixture

DoG Mixture

1.0

GEF Mixture

Gaussian Mixture

1.0

0.5

0.5

0.5

0.5

0.0

0.0

0.5

0.0

0.0

y

y

y

y

1.0

0.5

0.5

1.5

0.5

1.0

2.0

1.0

1.0

1.5

2.5

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 23. Numerical Simulation Examples of Fitting Gaussians with Real Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for Gaussian signals with Real weights mixtures (can be negative). The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the Gaussian with few components while LoG and DoG are more stable for a larger number of components.

y

y

y

y

0.4

0.4

0.4

0.2

0.0

0.2

0.2

0.2

0.2

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a half_sinusoid Function, N=5, loss=0.01

Overfitting LoG Mixture to a half_sinusoid Function, N=5, loss=0.09

Overfitting General Mixture to a half_sinusoid Function, N=5, loss=0.00

Overfitting Gaussian Mixture to a half_sinusoid Function, N=5, loss=0.00

1.0

True half_sinusoid

True half_sinusoid

1.0

True half_sinusoid

1.0

1.0

True half_sinusoid

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.4

0.4

0.4

0.2

0.2

0.0

0.2

0.2

0.2

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a half_sinusoid Function, N=8, loss=0.01

Overfitting LoG Mixture to a half_sinusoid Function, N=8, loss=0.01

Overfitting General Mixture to a half_sinusoid Function, N=8, loss=nan

Overfitting Gaussian Mixture to a half_sinusoid Function, N=8, loss=0.00

1.0

True half_sinusoid

1.0

1.0

True half_sinusoid

True half_sinusoid

1.0

True half_sinusoid

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.4

0.4

0.4

0.2

0.0

0.2

0.2

0.2

0.2

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a half_sinusoid Function, N=10, loss=0.00

Overfitting LoG Mixture to a half_sinusoid Function, N=10, loss=0.01

Overfitting General Mixture to a half_sinusoid Function, N=10, loss=nan

Overfitting Gaussian Mixture to a half_sinusoid Function, N=10, loss=nan

1.0

True half_sinusoid

1.0

1.0

True half_sinusoid

True half_sinusoid

1.0

True half_sinusoid

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.2

0.4

0.4

0.4

0.0

0.2

0.2

0.2

0.2

0.0

0.0

0.0

0.4

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting DoG Mixture to a half_sinusoid Function, N=20, loss=0.00

Overfitting LoG Mixture to a half_sinusoid Function, N=20, loss=0.00

Overfitting General Mixture to a half_sinusoid Function, N=20, loss=nan

Overfitting Gaussian Mixture to a half_sinusoid Function, N=20, loss=nan

1.0

True half_sinusoid

1.0

True half_sinusoid

True half_sinusoid

1.0

True half_sinusoid

1.0

DoG Mixture

LoG Mixture

GEF Mixture

Gaussian Mixture

0.8

0.8

0.8

0.8

0.6

0.6

0.6

0.6

0.4

y

y

y

y

0.2

0.4

0.4

0.4

0.0

0.2

0.2

0.2

0.2

0.4

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 24. Numerical Simulation Examples of Fitting Half sinusoids with Positive Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for half sinusoid signals with positive weights mixtures. The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the half sinusoid with few components while LoG and DoG are more stable for a larger number of components.

y

y

y

y

0.4

0.4

0.4

0.2

0.0

0.2

0.2

0.2

0.2

0.0

0.0

0.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a half_sinusoid Function, N=5, loss=0.08

Overfitting DoG Mixture to a half_sinusoid Function, N=5, loss=0.01

Overfitting General Mixture to a half_sinusoid Function, N=5, loss=0.00

Overfitting Gaussian Mixture to a half_sinusoid Function, N=5, loss=0.01

2.5

True half_sinusoid

True half_sinusoid

True half_sinusoid

True half_sinusoid

1.5

LoG Mixture

DoG Mixture

2.0

1.5

2.0

GEF Mixture

Gaussian Mixture

1.5

1.0

1.0

1.5

1.0

0.5

0.5

1.0

0.5

y

y

0.5

0.0

y

0.0

y

0.0

0.0

0.5

0.5

0.5

0.5

1.0

1.0

1.0

1.5

1.0

1.5

1.5

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a half_sinusoid Function, N=8, loss=0.02

Overfitting DoG Mixture to a half_sinusoid Function, N=8, loss=0.00

Overfitting General Mixture to a half_sinusoid Function, N=8, loss=0.00

Overfitting Gaussian Mixture to a half_sinusoid Function, N=8, loss=0.00

True half_sinusoid

1.0

True half_sinusoid

1.5

True half_sinusoid

True half_sinusoid

1.5

LoG Mixture

1.5

DoG Mixture

GEF Mixture

Gaussian Mixture

0.8

1.0

1.0

0.6

1.0

0.5

0.5

0.4

0.0

0.5

y

0.0

y

y

y

0.2

0.5

0.5

0.0

0.0

1.0

1.0

0.2

0.5

1.5

1.5

0.4

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a half_sinusoid Function, N=10, loss=0.01

Overfitting DoG Mixture to a half_sinusoid Function, N=10, loss=0.00

Overfitting General Mixture to a half_sinusoid Function, N=10, loss=0.00

Overfitting Gaussian Mixture to a half_sinusoid Function, N=10, loss=0.00

2.0

1.0

True half_sinusoid

True half_sinusoid

True half_sinusoid

True half_sinusoid

LoG Mixture

1.5

DoG Mixture

1.5

GEF Mixture

1.5

Gaussian Mixture

0.8

1.0

1.0

0.6

1.0

0.5

0.4

0.5

0.5

0.0

y

y

y

y

0.2

0.5

0.0

0.0

0.0

1.0

0.5

0.5

0.2

1.5

1.0

1.0

0.4

2.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

Overfitting LoG Mixture to a half_sinusoid Function, N=20, loss=0.00

Overfitting DoG Mixture to a half_sinusoid Function, N=20, loss=0.00

Overfitting General Mixture to a half_sinusoid Function, N=20, loss=0.00

Overfitting Gaussian Mixture to a half_sinusoid Function, N=20, loss=0.00

True half_sinusoid

2.0

1.00

True half_sinusoid

2.5

True half_sinusoid

True half_sinusoid

LoG Mixture

2.0

DoG Mixture

GEF Mixture

Gaussian Mixture

1.5

0.75

2.0

1.5

1.0

1.5

0.50

1.0

1.0

0.5

0.25

0.5

y

0.5

y

0.0

y

y

0.00

0.0

0.0

0.5

0.25

0.5

0.5

1.0

0.50

1.0

1.5

1.0

0.75

1.5

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

10.0 7.5 5.0 2.5 0.0 2.5 5.0 7.5 10.0

x

x

x

x

- Figure 25. Numerical Simulation Examples of Fitting Half sinusoids with Real Weights Mixtures ( N= 2, 5, 8, and 10 ). We show some fitting examples for half sinusoid signals with Real weights mixtures (can be negative). The four mixtures used from left to right are Gaussians, LoG, DoG, and General mixtures. From top to bottom: N = 2, 8, and 10 components. The optimized individual components are shown in green. Some examples fail to optimize due to numerical instability in both Gaussians and GEF mixtures. Note that GEF is very efficient in fitting the half sinusoid with few components while LoG and DoG are more stable for a larger number of components.

#### B. Genealized Exponential Splatting Details

##### B.1. Upper Bound on the Boundary ViewDependant Error in the Approximate GES Rasterization

Given the Generalized Exponential Splatting (GES) function defined in Eq.(2) and our approximate rasterization given by Eq.(3),4, and 5, we seek to establish an upper bound on the error of our approximation in GES rendering. Since it is very difficult to estimate the error accumulated in each individual pixel from Eq.(3), we seek to estimate the error directly on each splatting component affecting the energy of all passing rays.

Let us consider a simple 2D case with symmetrical components as in Fig.6. The error between the scaled Gaussian component and the original GES component is related to the energy loss of rays and can be represented by simply estimating the ratio η between the area difference and the area of the scaled Gaussian. Here we will show we can estimate an upper bound on η relative to the area of each component.

For the worst-case scenario when β → ∞, we consider two non-overlapping conditions for the approximation: one where the square is the outer shape and one where the circle covers the square. The side length of the square is 2r for the former case and 2r/√2 for the latter case. The radius r of the circle is determined by the effective projected variance α from Eq.(4). For a square with side length 2r and a circle with radius r, we have: Asquare = 4r2,Acircle = πr2. For a square with side length 2r/√2, the area is:Asquare, covered = 2r2.

The area difference ∆A is: ∆Asquare larger = Asquare − Acircle = 4r2 − πr2, (29)

∆Acircle larger = Acircle − Asquare, covered = πr2 − 2r2.

(30)

The ratio of the difference in areas to the area of the inner shape, denoted as η, is bounded by:

4r2 − πr2 πr2 ≈ 0.2732,

∆Asquare larger Acircle

ηsquare larger =

=

(31) ηcircle larger =

πr2 − 2r2 πr2 ≈ 0.3634. (32)

∆Acircle larger Acircle

=

Due to the PDF normalization constraint in GND [14], the approximation followed in Eq.(4), and 5 will always ensure ηsquare larger ≤ η ≤ ηcircle larger. Thus, our target ratio η when using our approximate scaling of variance based on β should be within the range 0.2732 ≤ η ≤ 0.3634. This implies in the worst case, our GES approximation will result in 36.34% energy error in the lost energy of all rays passing through all the splatting components. In practice, the error will be much smaller due to the large number of components and the small scale of all the splatting components.

##### B.2. Implementation Details

Note that the DoG in Eq.(7) will be very large when σ2 is large, so we downsample the ground truth image by a factor ‘scaleim,freq‘ and upsample the mask Mω similarly before calculating the loss in Eq.(8). In the implementation of our Generalized Exponential Splatting (GES ) approach, we fine-tuned several hyperparameters to optimize the performance. The following list details the specific values and purposes of each parameter in our implementation:

- • Iterations: The algorithm ran for a total of 40,000 iterations.
- • Learning Rates:

- – Initial position learning rate (lrpos, init) was set to 0.00016.
- – Final position learning rate (lrpos, final) was reduced to 0.0000016.
- – Learning rate delay multiplier (lrdelay mult) was set to 0.01.
- – Maximum steps for position learning rate (lrpos, max steps) were set to 30,000.

- • Other Learning Rates:

- – Feature learning rate (lrfeature) was 0.0025.
- – Opacity learning rate (lropacity) was 0.05.
- – Shape and rotation learning rates (lrshape and lrrotation) were both set to 0.001.
- – Scaling learning rate (lrscaling) was 0.005.

- • Density and Pruning Parameters:

- – Percentage of dense points (percentdense) was 0.01.
- – Opacity and shape pruning thresholds were set to 0.005.

- • Loss Weights and Intervals:

- – SSIM loss weight (λssim) was 0.2.
- – Densification, opacity reset, shape reset, and shape pruning intervals were set to 100, 3000, 1000, and 100 iterations, respectively.

- • Densification Details:

- – Densification started from iteration 500 and continued until iteration 15,000.
- – Gradient threshold for densification was set to 0.0003.

- • Image Laplacian Parameters:

- – Image Laplacian scale factor (scaleim,freq) was 0.2.
- – Weight for image Laplacian loss (λω) was 0.5.

• Miscellaneous:

– Strength of shape ρ was set to 0.1.

These parameters were carefully chosen to balance the trade-off between computational efficiency and the fidelity of the synthesized views. The above hyperparameter configuration played a crucial role in the effective implementation of our GES approach. For implementation purposes, the modification functions have been shifted by -2 and the β initialization is set to 0 instead of 2 ( which should not have any effect on the optimization).

#### C. Additional Results and Analysis

##### C.1. Additional Results

We show in Fig.32 additional GES results (test views) and comparisons to the ground truth and baselines. In Fig.33, show PSNR, LPIPS, SSIM, and file size results for every single scene in MIPNeRF 360 dataset [5, 6] of our GES and re-running the Gaussian Splatting [27] baseline with the exact same hyperparameters of our GES and on different number of iterations.

##### C.2. Applying GES in Fast 3D Generation

GES is adapted to modern 3D generation pipelines using score distillation sampling from a 2D text-to-image model [50], replacing Gaussian Splatting for improved efficiency. We employ the same setup as DreamGaussian [68], altering only the 3D representation to GES . This change demonstrates GES ’s capability for real-time representation applications and memory efficiency.

For evaluation, we use datasets NeRF4 and RealFusion15 with metrics PSNR, LPIPS [87], and CLIPsimilarity [53] following the benchmarks in Realfusion [41] and Magic123 [52]. Our GES exhibits swift optimization with an average runtime of 2 minutes, maintaining quality, as shown in Table 3 and Fig.26.

##### C.3. Shape Parameters

In Table 5, we explore the effect of all hyperparameters associated with the new shape parameter on novel view synthesis performance. We find that the optimization process is relatively robust to these changes, as it retains relatively strong performance and yields results with similar sizes.

Density Gradient Threshold. In Fig.27, we visualize the impact of modifying the density gradient threshold for splitting, using both GES and the standard Gaussian Splatting ( after modifying the setup for a fair comparison to GES ). We

Dataset Metrics\Methods Point-E DreamGaussian GES (Ours)

|NeRF4<br><br>|CLIP-Similarity↑ 0.48 0.56 0.58 PSNR↑ 0.70 13.48 13.33<br><br>|
|---|---|
|RealFusion15<br><br>|CLIP-Similarity↑ 0.53 0.70 0.70 PSNR↑ 0.98 12.83 12.91<br><br>|

- Average Runtime ↓ 78 secs 2 mins 2 mins

- Table 3. GES Application: Fast Image-to-3D Generation pipeline We show quantitative results in terms of CLIPSimilarity↑ / PSNR↑ , and Runtime↓, compared to fast methods: Point-E [46] and DreamGaussian [68] . GES offers a good option for a fast and effective image-to-3D solution.

see that the threshold has a significant impact on the tradeoff between performance and size, with a higher threshold decreasing size at the expense of performance. Notably, we see that GES outperforms GS across the range of density gradient thresholds, yielding similar performance while using less memory.

- C.4. Analysing the Frequency-Modulated Image Loss

We study the effect of the frequency-modulated loss Lω on the performance by varying λω and show the results in Table 4 and Table 2. Note that increasing λω in GES indeed reduces the size of the file, but can affect the performance. We chose λω = 0.5 as a middle ground between improved performance and reduced file size.

- C.5. Visualizing the Distribution of Parameters

We visualize the distribution of shape parameters β in Fig.28 and the sizes of the splatting components in Fig.29. They clearly show a smooth distribution of the components in the scene, which indicates the importance of initialization. This hints a possible future direction in this line of research.

- C.6. Typical Convergence Plots

We show in Fig.30 examples of the convergence plots of both GES and Gaussians if the training continues up to 50K iterations to inspect the diminishing returns of more training. Despite requiring more iterations to converge, GES trains faster than Gaussians due to its smaller number of splatting components.

Realfusion15 NeRF4 StableDiffusion-XL

[Figure 80]

Reference

Source view

λfreq Method PSNR LPIPS SSIM Size Deep Blending 0.05

- Novel view 1
- Novel view 2

GES 29.58 0.252 0.900 431 GES (fixed β = 2) 29.53 0.251 0.901 433

GES 29.54 0.252 0.901 428 GES (fixed β = 2) 29.61 0.252 0.901 435

0.10

- Figure 26. Visulization for 3D generation. We show selected generated examples by GES from Realfusion15 (left) and NeRF4 datasets (middle). Additionally, we pick two text prompts: ”a car made out of sushi” and ”Michelangelo style statue of an astronaut”, and then use StableDiffusion-XL [49] to generate the reference images before using GES on them(right).

0.0001 0.0001 0.0002 0.0002 0.0003 0.0003 0.0004

0.20

0.22

0.24

0.26

0.0001 0.0001 0.0002 0.0002 0.0003 0.0003 0.0004

256

512

1024

2048

Method

Gaussians

Ours

Densification Threshold

LPIPS(lowerisbetter)FileSize(lowerisbetter)

- Figure 27. Ablation Study of Densification Threshold on Novel View Synthesis. Impact of the densification threshold on reconstruction quality (LPIPS) and file size (MB) for our method and Gaussian Splatting [27], averaged across all scenes in the MipNeRF dataset. We see that the densification threshold has a significant impact on both file size and quality. Across the board, our method produces smaller scenes than Gaussian Splatting with similar or even slightly improved performance.

GES 29.66 0.251 0.901 397

0.50

- GES (fixed β = 2) 29.61 0.252 0.901 437

0.90

GES 27.21 0.259 0.899 366

- GES (fixed β = 2) 29.62 0.252 0.901 434 MipNeRF

GES 27.08 0.250 0.796 405

0.05

- GES (fixed β = 2) 27.05 0.250 0.795 411

0.10

GES 27.05 0.250 0.795 403

- GES (fixed β = 2) 27.05 0.250 0.796 412

GES 26.97 0.252 0.794 376 GES (fixed β = 2) 27.09 0.250 0.796 415

0.50

GES 25.82 0.255 0.792 364 GES (fixed β = 2) 27.08 0.250 0.795 413

0.90

Tanks and Temples 0.05

GES 23.49 0.196 0.837 251 GES (fixed β = 2) 23.55 0.196 0.836 255

GES 23.54 0.196 0.837 247 GES (fixed β = 2) 23.53 0.196 0.837 255

0.10

GES 23.35 0.197 0.836 221 GES (fixed β = 2) 23.65 0.196 0.837 256

0.50

GES 22.65 0.200 0.834 210 GES (fixed β = 2) 23.50 0.197 0.836 256

0.90

Table 4. Ablation of λfreq. We show a comparison of performance (PSNR, LPIPS, SSIM) for various values of λfreq. Note that increasing λfreq in GES indeed reduces the size of the file, but can affect the performance. We chose λfreq = 0.5 as a middle ground between improved performance and reduced file size.

60000

40000

Frequency

20000

0

1.0 1.5 2.0 2.5 3.0

Shape Value ( )

- Figure 28. Distribution of Shape Values. We show a distribution of β values of a converged GES initialized with β = 2. It shows a slight bias to β smaller than 2.

5 10 15 20

Sizes

0

500

1000

Frequency

L 2 L

| |
|---|

- Figure 29. Distribution of Sizes. We show a distribution of sizes (L2 and L∞) of the GES components of a converged scene.

Shape Learning Rate

PSNR SSIM LPIPS File Size (MB)

0.0005 26.83 0.845 0.141 659 0.0010 26.85 0.845 0.141 658 0.0015 26.89 0.846 0.141 651 0.0020 26.82 0.844 0.142 658

Shape Reset Interval

PSNR SSIM LPIPS File Size (MB)

200 26.87 0.845 0.141 656 500 26.86 0.845 0.141 658 1000 26.89 0.846 0.141 651 2000 26.84 0.845 0.141 657 5000 26.84 0.845 0.141 661

Shape Strength

PSNR SSIM LPIPS File Size (MB)

0.010 26.87 0.845 0.141 661 0.050 26.84 0.845 0.141 653 0.100 26.89 0.846 0.141 651 0.150 26.83 0.844 0.142 656

Ablation Setup PSNR↑ SSIM↑ LPIPS↓ Size (MB)↓

Gaussians 23.14 0.841 0.183 411 GES w/o Lω 23.54 0.836 0.197 254 GES w/ random β init. 23.37 0.836 0.198 223 GES w/ β = 2 init. 23.35 0.836 0.198 222

Table 6. Ablation Study on Novel View Synthesis. We study the impact of several components in GES on the reconstruction quality and file size in the Tanks & Temples dataset.

Table 5. Ablation Study on Novel View Synthesis. Impact of the shape parameter’s learning rate, reset interval, and strength on reconstruction quality and file size for the garden scene from the Mip-NeRF dataset.

L1 Loss Train Loss Train PSNR

[Figure 81]

[Figure 82]

[Figure 83]

Number of Components Test Loss Test PSNR

[Figure 84]

[Figure 85]

[Figure 86]

- Figure 30. Convergence Plots of Gaussians vs. GES . We show an example of the convergence plots of both GES and Gaussians if the training continues up to 50K iterations to inspect the diminishing returns of more training. Despite requiring more iterations to converge, GES trains faster than Gaussians due to its smaller number of splatting components.

[Figure 87]

[Figure 88]

[Figure 89]

[Figure 90]

[Figure 91]

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

[Figure 104]

[Figure 105]

[Figure 106]

- Figure 31. Frequency-Modulated Image Masks. For the input example image on the top left, We show examples of the frequency loss masks Mω used in Sec.4.3 for different numbers of target normalized frequencies ω ( ω = 0% for low frequencies to ω = 100% for high frequencies). This masked loss helps our GES learn specific bands of frequencies. Note that due to Laplacian filter sensitivity for high-frequencies, the mask for 0 < ω ≤ 50% is defined as 1 − Mω for 50 < ω ≤ 100%. This ensures that all parts of the image will be covered by one of the masks Mω, while focusing on the details more as the optimization progresses.

Ground Truth GES (Ours) Gaussians Mip-NeRF360 InstantNGP

[Figure 107]

[Figure 108]

[Figure 109]

[Figure 110]

[Figure 111]

[Figure 112]

[Figure 113]

[Figure 114]

[Figure 115]

[Figure 116]

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

[Figure 117]

[Figure 118]

[Figure 119]

[Figure 120]

[Figure 121]

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

[Figure 122]

[Figure 123]

[Figure 124]

[Figure 125]

[Figure 126]

[Figure 127]

[Figure 128]

[Figure 129]

[Figure 130]

[Figure 131]

[Figure 132]

[Figure 133]

[Figure 134]

[Figure 135]

[Figure 136]

[Figure 137]

[Figure 138]

[Figure 139]

[Figure 140]

[Figure 141]

[Figure 142]

[Figure 143]

[Figure 144]

[Figure 145]

[Figure 146]

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

| |
|---|

[Figure 147]

[Figure 148]

[Figure 149]

[Figure 150]

[Figure 151]

[Figure 152]

[Figure 153]

[Figure 154]

[Figure 155]

[Figure 156]

[Figure 157]

[Figure 158]

[Figure 159]

[Figure 160]

[Figure 161]

- Figure 32. Comparative Visualization Across Methods. Displayed are side-by-side comparisons between our proposed method and established techniques alongside their respective ground truth imagery. The depicted scenes are ordered as follows: BICYCLE, GARDEN, STUMP, COUNTER, and ROOM from the Mip-NeRF360 dataset; PLAYROOM and DRJOHNSON from the Deep Blending dataset, and TRUCK and TRAIN from Tanks&Temples. Subtle variances in rendering quality are accentuated through zoomed-in details. It might be difficult to see differences between GES and Gaussians because they have almost the same PSNR (despite GES requiring 50% less memory).

bicycle drjohnson counter bonsai garden playroom room truck kitchen train stump

method

| | |
|---|---|
| | |
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |
| | |

30

Gaussian

| | |
|---|---|
| | |
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |
| | |

GES

| | |
|---|---|
| | |
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |
| | |

25

| | |
|---|---|
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |

20

PSNR

15

10

5

0

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

value value value value value value value value value value value

bicycle drjohnson counter bonsai garden playroom room truck kitchen train stump

0.4

method

| | |
|---|---|
| | |
| | |
| | |
| | |

Gaussian

0.35

| | |
|---|---|
| | |
| | |
| | |

GES

| | |
|---|---|
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |

0.3

| | |
|---|---|
| | |
| | |

| | |
|---|---|
| | |
| | |

0.25

| | |
|---|---|
| | |
| | |

| | |
|---|---|
| | |
| | |

LPIPS

| | |
|---|---|
| | |

| | |
|---|---|
| | |

0.2

| | |
|---|---|

0.15

0.1

0.05

0

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

value value value value value value value value value value value

bicycle drjohnson counter bonsai garden playroom room truck kitchen train stump

method

| | |
|---|---|
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |

Gaussian

| | |
|---|---|
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |
| | |

GES

0.8

| | |
|---|---|
| | |
| | |

| | |
|---|---|
| | |
| | |

| | |
|---|---|
| | |
| | |

0.6

SSIM

0.4

0.2

0

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

value value value value value value value value value value value

bicycle drjohnson counter bonsai garden playroom room truck kitchen train stump

method

| | |
|---|---|
| | |
| | |
| | |

| | |
|---|---|
| | |
| | |

700

Gaussian

GES

| | |
|---|---|
| | |
| | |

600

| | |
|---|---|
| | |

500

FileSize

400

| | |
|---|---|

| | |
|---|---|

300

200

100

0

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

40000

30000

7000

value value value value value value value value value value value

- Figure 33. Detailed Per Scene Results On MipNeRF 360 for Different Iteration Numbers. We show PSNR, LPIPS, SSIM, and file size results for every single scene in MIPNeRF 360 dataset [5] of our GES and re-running the Gaussian Splatting [27] baseline with the exact same hyperparameters of our GES and on different number of iterations.

Ground Truth GES (full) GES (w/o Lω ) Gaussian Splatting [27]

[Figure 162]

[Figure 163]

[Figure 164]

[Figure 165]

| |
|---|

| |
|---|

| |
|---|

| |
|---|

[Figure 166]

[Figure 167]

[Figure 168]

[Figure 169]

| |
|---|

| |
|---|

| |
|---|

| |
|---|

- Figure 34. Frequency-Modulated Loss Effect. We show the effect of the frequency-modulated image loss Lω on the performance on novel views synthesis. Note how adding this Lω improves the optimization in areas where large contrast exists or where a smooth background is rendered.

