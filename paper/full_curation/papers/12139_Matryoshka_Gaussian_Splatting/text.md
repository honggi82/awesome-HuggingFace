## Matryoshka Gaussian Splatting

Zhilin Guo1 , Boqiao Zhang1 , Hakan Aktas1 , Kyle Fogarty1 , Jeffrey Hu1 , Nursena Koprucu Aslan1 , Wenzhao Li1 , Canberk Baykal1 , Albert Miao1 , Josef Bengtson2 , Chenliang Zhou1 ,

Weihao Xia1⋆ , Cristina Nader Vasconcelos3 , Cengiz Oztireli1,3

1University of Cambridge 2Chalmers University of Technology 3Google https://ZhilinGuo.github.io/MGS

# arXiv:2603.19234v2[cs.CV]20Mar2026

Abstract. The ability to render scenes at adjustable fidelity from a single model, known as level of detail (LoD), is crucial for practical deployment of 3D Gaussian Splatting (3DGS). Existing discrete LoD methods expose only a limited set of operating points, while concurrent continuous LoD approaches enable smoother scaling but often suffer noticeable quality degradation at full capacity, making LoD a costly design decision. We introduce Matryoshka Gaussian Splatting (MGS), a training framework that enables continuous LoD for standard 3DGS pipelines without sacrificing full-capacity rendering quality. MGS learns a single ordered set of Gaussians such that rendering any prefix, the first k splats, produces a coherent reconstruction whose fidelity improves smoothly with increasing budget. Our key idea is stochastic budget training: each iteration samples a random splat budget and optimises both the corresponding prefix and the full set. This strategy requires only two forward passes and introduces no architectural modifications. Experiments across four benchmarks and six baselines show that MGS matches the full-capacity performance of its backbone while enabling a continuous speed–quality trade-off from a single model. Extensive ablations on ordering strategies, training objectives, and model capacity further validate the designs.

Keywords: 3D Gaussian splatting · continuous level of detail · nested representations · budgeted rendering · stochastic training

### 1 Introduction

Real-time neural rendering is governed by a fundamental tension between scene fidelity and the computational budget available [25,30]. This budget varies by orders of magnitude across the hardware spectrum, from high-end GPU workstations to mobile devices and mixed-reality headsets [28,37]; and fluctuates dynamically at runtime by viewpoint and scene complexity [9,45]. Level of detail (LoD) techniques address this tension by scaling the rendered representation to match available resources and have long been a cornerstone of interactive graphics [24]. The dominant paradigm, discrete LoD, precomputes a set of quality levels and

⋆ Corresponding author: wx258@cam.ac.uk

[Figure 1]

Fig. 1: Continuous LoD need not sacrifice full-capacity quality to enable budget tradeoff. Our method, MGS (top), learns an ordered set of Gaussian primitives whose prefixes yield coherent reconstructions at any splat budget. Compared to CLoD-3DGS [26] (mid) and CLoD-GS [4] (bot), MGS achieves the highest fidelity at every operating point with quality degrading gracefully under budget reduction. Scene: Garden [1].

switches between them at runtime [5]. A coarse set of fixed levels, however, cannot smoothly track a budget that shifts continuously with scene content and viewpoint, and the abrupt transitions between levels produce visible pop-in and pop-out artifacts [9,10].

3D Gaussian Splatting (3DGS) [15] achieves photorealistic novel view synthesis by rasterizing millions of anisotropic Gaussian primitives at real-time frame rates, with computational cost scaling directly with the number of primitives [8]. In principle, this primitive-based nature of the representation offers continuous budget control, since omitting any subset of splats yields an immediate speedup [11,15]. Yet a conventionally trained 3DGS model has no ordering among its primitives, so quality collapses rapidly as splats are removed [21].

Existing approaches attempt to introduce LoD to 3DGS through several strategies. Discrete LoD methods [16, 19, 31, 33] build hierarchical structures over Gaussian primitives, exposing a limited number of quality levels but requiring auxiliary index structures and offering only coarse budget granularity. Compression and pruning pipelines [6,22,36] can approximate multi-budget behaviour, but each operating point is typically obtained independently without ensuring that subsets are nested or globally coherent. Concurrent continuous LoD methods [4,26] enable smoother scaling within a single model, but often incur substantial quality degradation at full capacity. As a result, adopting LoD in 3DGS remains a costly design choice that often sacrifices reconstruction quality.

In this work, we introduce Matryoshka Gaussian Splatting (MGS), a training framework that enables continuous LoD control without degrading full-capacity quality Fig. 1. Where Matryoshka Representation Learning [20] nests several embedding dimensions, MGS transfers this principle to scene primitives at arbitrary granularity. Concretely, MGS learns an ordered set of Gaussian primitives such that any prefix (the first k splats) forms a coherent scene representation,

[Figure 2]

Fig. 2: Framework of Matryoshka Gaussian Splatting.

with reconstruction fidelity improving smoothly as k increases. Rendering at different budgets is then achieved by truncating the ordered sequence, producing a continuous spectrum of quality-speed operating points from a single model.

The key mechanism is stochastic budget training: each iteration samples a random splat budget uniformly and optimises both the corresponding prefix and the full set, requiring only two forward passes each training step. Because this procedure modifies only the training objective and not the model architecture, it integrates into most existing 3DGS pipelines with minimal implementation effort. At deployment, one adjusts k to match available resources—no per-budget retraining, no auxiliary data structures.

Extensive experiments across four benchmarks [1, 12, 18, 39] and six baselines [4, 16, 22, 26, 31, 36] spanning discrete LoD and continuous LoD methods demonstrate that MGS matches the full-capacity reconstruction quality of its backbone, while enabling a continuous quality-speed frontier from a single model.

Our contributions are summarised as follows:

- – We introduce Matryoshka Gaussian Splatting (MGS), which learns an nested Gaussian primitive representation where any prefix yields a coherent scene reconstruction, enabling continuous LoD control.
- – We propose stochastic budget training, a simple yet effective model-agnostic training procedure that optimises across a continuous budget range with only two renders per iteration.
- – We provide extensive evaluation on four benchmarks against six baselines, demonstrating state-of-the-art quality-speed performance, with ablations on importance scoring, budget sampling, and training objective.

### 2 Related Work

- 2.1 3D Gaussian Splatting

##### 3D Gaussian Splatting (3DGS) [15] replaces implicit volumetric representations in Neural Radiance Fields [25] with explicit anisotropic Gaussian primitives

rendered via differentiable rasterization. This formulation enables photorealistic novel view synthesis at real-time frame rates, with rendering cost scaling directly with the number of primitives, making primitive count a natural axis for controlling computational budget. Subsequent work [7,17,40,43] has extended 3DGS along several directions. For capacity control, the original densification heuristics offer no direct control over the final primitive count. 3DGS-MCMC [17] addresses this via Langevin-dynamics sampling under a fixed budget. Mini-Splatting [7] further improves densification under constrained capacities. For multi-scale rendering, Mip-Splatting [43] and Multi-Scale 3DGS [40] introduce anti-aliasing filters that improve quality when viewed at varying observation scales. Our method MGS builds upon these advances by learning a primitive ordering that maintains coherent reconstructions across a continuous range of rendering budgets.

#### 2.2 Level-of-Detail Rendering

Level-of-detail (LoD) rendering enables adaptive control of rendering cost by varying scene complexity according to available computational budgets. Discrete LoD [16,19,23,31,33,34] and progressive streaming [3,35] methods construct hierarchical or layered structures over Gaussians to expose multiple quality levels. However, these methods require auxiliary index structures and typically provide only a small number of discrete operating points [16,31]. Compression and pruning pipelines [6,22,36] can approximate multi-budget behaviour by applying importance-based pruning or quantization at varying targets, but each operating point is typically obtained independently without ensuring nested or globally consistent primitive subsets [27,29]. Concurrent continuous LoD methods [4,26] target smoother budget scaling within a single model, either by learning viewdependent opacity decay [14] or by training on random primitive subsets. However, both incur noticeable quality degradation at full capacity and rapid quality collapse at reduced budgets, making continuous LoD a costly design choice. In contrast, MGS learns a single ordered set of Gaussian primitives such that every prefix yields a coherent reconstruction. This produces a dense continuum of valid budgets while still closely matching the backbone’s full-capacity quality.

#### 2.3 Nested (Matryoshka) Representations

Nested representations learn ordered structures in which every prefix of the representation remains independently usable. This idea was introduced by nested dropout [32] and scaled to high-dimensional embeddings by Matryoshka Representation Learning (MRL) [20]. Related ideas of packing multiple capacity levels into a single model have also been explored in slimmable networks [2,42], which train neural networks that operate at different channel widths, although these methods typically require separate forward passes for each width configuration. In classical graphics, progressive meshes [13] provide an analogous concept by representing geometry as an ordered sequence of refinement operations that enables continuous mesh simplification. MGS transfers the nested representation

principle to Gaussian scene primitives to enable continuous control over rendering budgets through ordered primitive prefixes within a single model.

### 3 Method

Our MGS consists of two components: (i) an ordered Gaussian representation where importance-ranked prefixes serve as nested scene representations at different fidelity levels (Sec. 3.2), and (ii) a stochastic training procedure that efficiently optimises across all prefix lengths using a single random prefix and the full set per iteration (Sec. 3.3). We first review the necessary background in Sec. 3.1.

#### 3.1 Preliminaries on 3DGS

3D Gaussian Splatting (3DGS) [15] represents a scene as a set of N anisotropic 3D Gaussians G = {gi}Ni=1. Each Gaussian gi carries a mean µi ∈ R3, a covariance Σi, an opacity σi ∈ [0,1], and view-dependent color parameters (e.g., spherical harmonics). Given a camera c, a pixel color is obtained via front-toback α-compositing of depth-sorted Gaussians:

- i−1
- j=1

N

ˆI(u) =

Ci(u)αi(u)

i=1

1 − αj(u) , (1)

where u is a pixel coordinate, Ci(u) the view-dependent color, and αi(u) the screen-space opacity obtained by evaluating the projected 2D Gaussian at u.

Given posed training images D = {(In,cn)}Mn=1, the model minimises a perimage reconstruction loss:

ℓ(G;I,c) := (1 − λ) R(G;c) − I 1 + λLD-SSIM R(G;c),I , (2) where R denotes the differentiable splatting renderer and λ is the mixing weight.

#### 3.2 Matryoshka Gaussian Splatting

We construct a nested Gaussian representation that enables continuous control over rendering budgets from a single model. Specifically, we (i) define an importance score to rank Gaussian primitives, (ii) organize them into an ordered prefix representation that supports variable-budget rendering, and (iii) adopt an capacity control mechanism to maintain a fixed Gaussian budget during training.

Importance Score. To construct a nested Gaussian representation, we assign each Gaussian primitive gi a scalar score s(gi) based on a per-primitive property. Gaussians are then sorted by this score so that the most important primitives appear first in the sequence.

The MGS formulation is agnostic to the choice of s(g); any statistic that induces a meaningful importance ordering is admissible. Empirically, we find that

sorting Gaussians by opacity in descending order yields stable behaviour across budgets. This is likely because opacity reflects the visibility and radiance contribution of each primitive, making it a natural criterion for ordering primitives so that early prefixes already capture the dominant scene structure. Therefore, we use primitive’s opacity as importance score in implementation:

s(gi) = σi, (3)

where σi denotes the opacity parameter of Gaussian gi. Alternative scoring criteria are evaluated in ablation studies.

Nested Primitive Representation. Let π be a permutation of {1,...,N} that ranks Gaussians by a scalar importance score s(g) in non-increasing order:

s gπ(1) ≥ s gπ(2) ≥ ··· ≥ s gπ(N) . (4) The k-prefix is the subset of the k highest-ranked Gaussians:

G≤k := {gπ(1),...,gπ(k)}, k ∈ {1,...,N}. (5)

Rendering with budget k produces ˆI≤k = R(G≤k;c). Because prefixes are nested (G≤k ⊂ G≤k′ for k < k′) and rasterization cost scales with the Gaussian count, varying k traces a continuous quality-speed curve from a single trained model without any per-budget retraining or model switching.

#### 3.3 Stochastic Budget Training

Training a single representation to perform well at every budget level is the central challenge of LoD. Optimizing all N possible budgets per step would be prohibitively expensive. We instead propose a stochastic procedure that covers a dense continuum of prefix sizes with only two forward passes per iteration.

Budget Sampling. At each training step we draw a random keep ratio and compute the corresponding prefix size k such that:

k = ⌈r N⌉, r ∼ Unif(rmin, 1), (6)

where rmin ∈ (0,1] is the smallest prefix fraction seen during training; rmin = 1 recovers standard 3DGS training. Uniform sampling ensures that every budget in [⌈rminN⌉, N] is visited with equal probability over training, yielding unbiased coverage of the full budget spectrum.

Training Objective. At each step, we sample a training view (I,c) ∼ D and prefix size k = ⌈rN⌉, render both the prefix and the full set, and minimise:

ℓMGS := ℓ(G≤k;I,c) + γ ℓ(G≤N;I,c), (7)

where γ ≥ 0 balances the prefix and full-set terms. The prefix term pressures the model to produce strong reconstructions from partial subsets, while the fullset term anchors full-quality performance. Over training, this stochastic procedure estimates the expected multi-budget objective across all budget fractions r ∈ [rmin,1] and all training views, with prefix membership determined by the ordering in Eq. (4). Each step incurs exactly two renders regardless of N.

Dynamic Reordering. Because gradient updates modify the Gaussian parameters at every step, the importance scores s(gi) evolve throughout training. After each training iteration, we recompute the permutation so that the ordering in Eq. (4) holds under the current parameters:

π ← argsort s , s = s(g1),...,s(gN) , (8)

in non-increasing order. This ensures every prefix G≤k always contains the k most important primitives under the current parameters.

### 4 Experiments

#### 4.1 Experimental Setup

Benchmarks. We evaluate MGS on four standard 3DGS benchmarks: MipNeRF 360 [1], Tanks & Temples [18], Deep Blending [12], and BungeeNeRF [39]. For all datasets, we follow the standard evaluation protocol and use the every8th-image split, where images with indices 0,8,16,... are reserved for testing.

Baselines. We compare MGS against six representative Gaussian LoD baselines. Discrete LoD methods expose a fixed set of quality levels, including H3DGS [16] (τ-threshold hierarchy), Octree-GS [31] (anchor-based octree LOD), MaskGaussian [22] (learnable existence probability), and FlexGaussian [36] (training-free pruning and quantization), each at the discrete operating points reported in respective papers. Continuous LoD methods support rendering at arbitrary splat budgets, including CLoD-GS [4] (distance-dependent opacity decay) and CLoD3DGS [26] (learned importance ordering), are evaluated at the same prefix ratios

- as MGS: 100%, 90%, ..., 20%, 10%, 5%, and 1%.

Metrics. We report image-quality metrics PSNR, SSIM [38], LPIPS [44]. In addition, a key requirement to evaluating LoD methods is comparing quality–speed trade-off at different operating points. To this end, we first define a composite quality score calculated at each operating point:

Q¯ = 13 p ˜+ s˜+ (1−ℓ˜) , (9)

where p˜, s˜, ℓ˜ are PSNR, SSIM, and LPIPS linearly clamped to [0,1] using fixed ranges (14,32), (0.35,0.92), and (0.06,0.60), respectively. We then summarise the full quality–speed trade-off with two area-under-the-curve (AUC) scores.

- Table 1: Quantitative comparison on four benchmarks. PSNR, SSIM [38], LPIPS [44] reported at highest splat budget per baseline. AUCfps summarises quality–FPS trade-off frontier, and AUCsplats encapsulates quality/splat efficiency. The best and second best results are highlighted. ↑ higher is better, ↓ lower is better.

MipNeRF 360 Tanks & Temples

Method

PSNR↑ SSIM↑ LPIPS↓ AUCfps↑ AUCsplats↑ PSNR↑ SSIM↑ LPIPS↓ AUCfps↑ AUCsplats↑ 3DGS-MCMC [17] 28.40 0.843 0.133 – – 24.76 0.877 0.083 – –

H3DGS [16] 25.41 0.780 0.230 11.62 60.51 20.41 0.808 0.186 8.23 58.84 FlexGaussian [36] 26.86 0.793 0.237 30.04 62.05 22.89 0.823 0.198 52.38 64.93 MaskGaussian [22] 27.42 0.815 0.218 34.11 67.10 23.66 0.846 0.181 45.15 68.89 Octree-GS [31] 27.62 0.813 0.221 21.61 68.43 24.59 0.865 0.157 23.80 67.81

Disc.

CLoD-GS [4] 26.55 0.803 0.233 19.39 63.43 22.78 0.832 0.193 23.39 65.37 CLoD-3DGS [26] 27.44 0.814 0.215 46.38 56.56 23.51 0.845 0.176 50.97 61.89 MGS (Ours) 28.20 0.841 0.130 64.81 77.79 24.56 0.874 0.086 70.16 77.54

Cont.

Deep Blending BungeeNeRF PSNR↑ SSIM↑ LPIPS↓ AUCfps↑ AUCsplats↑ PSNR↑ SSIM↑ LPIPS↓ AUCfps↑ AUCsplats↑ 3DGS-MCMC [17] 27.63 0.893 0.204 – – 27.04 0.903 0.091 – –

Method

H3DGS [16] 27.77 0.882 0.277 10.39 73.82 27.74 0.910 0.114 8.47 62.57 FlexGaussian [36] 29.25 0.899 0.251 43.61 75.53 25.87 0.872 0.129 12.89 53.58 MaskGaussian [22] 29.69 0.907 0.245 54.96 78.77 27.80 0.917 0.099 21.58 71.18 Octree-GS [31] 30.35 0.910 0.252 29.54 83.21 28.23 0.922 0.088 19.69 73.70

Disc.

CLoD-GS [4] 29.03 0.901 0.249 26.09 77.34 25.35 0.859 0.148 13.83 65.40 CLoD-3DGS [26] 29.54 0.903 0.247 69.36 72.33 26.57 0.892 0.131 24.45 29.72 MGS (Ours) 28.41 0.902 0.176 82.63 83.22 27.13 0.906 0.088 62.99 79.93

Cont.

AUCfps(↑): we construct a monotone envelope of quality versus FPS. Noting that an operating point can be replicated at any lower speed, the envelope extends leftward from every achieved operating point along lowering throughput. We clip FPS to [0, 500] and compute the normalised area under this envelope.

AUCsplat(↑): we construct a monotone envelope of quality vs splat count. Noting that any operating point can be replicated with additional splats, the envelope extends rightward from all operating points along increasing splat count. Also noting that quality diminishes as splat count approaches 0, we connect the origin (0,0) to the lowest-budget operating point. We clip budget to [0, 5M] and compute the normalised area under this envelope.

Both AUCfps and AUCsplat are scaled by 100 for enhanced readability.

Implementation. We implement MGS on gsplat [41] codebase using 3DGSMCMC [17] training strategy. Unless otherwise noted, we order splats by opacity in descending order (Eq. (4)), use equal prefix/full weights (γ=1, Eq. (7)), set the full-scene capacity to N=5M (Eq. (4)), and train for 50k iterations. All experiments are conducted on identical Ubuntu servers with NVIDIA A100 GPU.

#### 4.2 Results and Comparisons

Full-splat Quality Comparison. Tab. 1 reports each method at its highest splat-count operating point, averaged per benchmark. On MipNeRF 360 [1], MGS achieves the best PSNR (28.20dB), SSIM (0.841), and LPIPS (0.130), outperforming the next-best LoD baseline (Octree-GS [31], 27.62dB) by +0.58dB

[Figure 3]

- Fig. 3: Quality-budget trade-off on Mip-NeRF 360 [1], averaged across all nine scenes. Left: Quality (Q¯, Eq. 9) vs. FPS. Right: Quality vs. number of Gaussian splats. Curves trace continuous LoD models across prefix ratios 1%–100%, and trace discrete LoD models at their recommended operating points respectively. MGS (ours, dark blue) achieves the highest quality at every speed and splat budget, while spanning a much wider FPS range than any baseline.

while achieving substantially lower perceptual error (LPIPS 0.130 vs. 0.221). On Tanks & Temples [18], MGS trails Octree-GS in PSNR by only 0.03dB (24.56 vs. 24.59) but achieves the best SSIM and LPIPS. On Deep Blending [12] and BungeeNeRF [39], Octree-GS obtains higher PSNR at its single highest-quality level; however, its coarser LoD levels incur severe quality degradation, yielding far lower AUC scores than MGS. MGS consistently achieves the lowest LPIPS, indicating strong perceptual quality across all the four benchmarks.

Quality–Speed Trade-off. MGS outperforms all baselines in both AUCfps and AUCsplats by wide margins across four benchmarks, sustaining high fidelity consistently across varying speed and budget constraints (Fig. 3). Qualitative comparisons also confirm that MGS preserves coherent scene structure

- at aggressive budget reductions (5–10% splats) Figs. 4 and 5, whereas CLoD3DGS and CLoD-GS suffer from severe artifacts; the one exception is DrJohnson, where CLoD-3DGS achieves higher peak PSNR at full budget yet degrades more sharply at reduced budgets.

By adjusting the prefix ratio from 1% to 100%, MGS produces a smooth, dense Pareto frontier of operating points from a single trained model, without any per-budget retraining or model switching. Among continuous-LoD competitors, CLoD-3DGS [26] achieves the next-highest AUCfps on MipNeRF 360 (28.94 vs. 54.46 for MGS) but at substantially lower image quality (27.44 vs. 28.20dB PSNR, 0.215 vs. 0.130 LPIPS). CLoD-GS [4] spans a narrower speed range, resulting in lower AUCfps (9.78 on MipNeRF 360). Discrete-LoD methods such

- as Octree-GS [31] and H3DGS [16] exhibit low AUC scores (AUCfps: 9.96 and 4.81 on MipNeRF 360), because their coarser levels incur severe quality drops. FlexGaussian [36] offers competitive quality through training-free compression

[Figure 4]

###### Fig. 4: Qualitative comparison of continuous LoD methods across four benchmarks. Renderings are shown at 5%, 10%, 30%, 60%, and 100% of the full splat budget. We compare MGS with CLoD-3DGS [26] and CLoD-GS [4]. Under highly constrained budgets (5–10%), MGS maintains coherent reconstructions with PSNR of 21–28 dB, while both baselines suffer from severe artifacts and quality collapse (11–17 dB).

[Figure 5]

###### Fig. 5: Additional qualitative results including a failure case. On stump, train, and rome, MGS maintains higher fidelity across all budget levels. On DrJohnson (bottom), CLoD-3DGS [26] achieves higher peak PSNR at 100% budget (29.1 vs. 27.7 dB); however, MGS still degrades more gracefully at reduced budgets (5–30%).

[Figure 6]

- Fig. 6: Ablations on the importance score. The opacity-descending dominates other importance scores across the full budget range.

but produces only a handful of discrete operating points and achieves lower AUC values than MGS across all benchmarks.

Continuous vs. Discrete Operating Points. A key practical advantage of MGS is the density of the operating-point frontier. MGS produces a coherent rendering for every integer splat budget k ∈ {1,...,N}; in practice, evaluating 12 budget ratios already yields a smooth quality–speed curve (Fig. 3). In contrast, Octree-GS [31] provides 3–6 LOD levels, H3DGS [16] offers 9 τ-thresholds, and FlexGaussian [36] exposes 2–6 compression targets, each requiring separate configurations. This distinction matters for deployment: MGS allows a system to respond to per-frame or per-device budgets by simply truncating the splat array, with no additional data structures, mode switches, or latency spikes.

Quality vs 3DGS-MCMC. Although MGS trains for all possible splat budgets, its full-quality performance closely approaches and sometimes exceeds that of stand-alone 3DGS-MCMC [17] backbone, which trains only for the full set and provides no LoD capability. On MipNeRF 360 and Tanks & Temples, MGS trails 3DGS-MCMC by only 0.20dB (28.20 vs. 28.40 and 24.56 vs. 24.76, respectively). On Deep Blending and BungeeNeRF, MGS surpasses 3DGS-MCMC (28.41 vs. 27.63dB and 27.13 vs. 27.04dB), suggesting that the stochastic budget objective can act as a beneficial regulariser on certain scene types. This confirms that continuous LoD need not come at the cost of full-capacity quality.

#### 4.3 Ablation Studies

We conduct controlled ablations on a single scene (bicycle from MipNeRF 360 [1]) with N=1M splats and 50k training steps unless otherwise noted, isolating each design choice while keeping the others at their default values Tab. 2.

Importance Score. We evaluate seven importance scores derived from four per-splat criteria s(g), i.e. opacity, volume, SH energy, and colour variance

- Table 2: Ablation study on importance score and budget training strategy. All metrics reported at split=1.0 (full budget). PSNR, SSIM and LPIPS represent raw

quality; AUCfps and AUCsplats summarise quality–efficiency frontiers. The best and second best results per column are highlighted. ↑ higher is better, ↓ lower is better.

PSNR↑ SSIM↑ LPIPS↓ AUCfps↑ AUCsplats↑

Opacity ↓ (ours) 25.47 0.776 0.174 68.62 61.05 Opacity ↑ 24.91 0.743 0.219 30.53 33.48

Color variance ↓ 25.25 0.770 0.183 51.94 46.26 SH energy ↓ 25.17 0.766 0.187 59.39 47.12 Volume ↓ 25.19 0.764 0.183 52.15 44.73

Importance Score

Fixed append 25.51 0.773 0.175 46.41 43.09 Fixed prepend 25.32 0.772 0.176 49.65 42.90

Prefix + full (ours) 25.43 0.776 0.175 66.87 60.96 Prefix 24.97 0.734 0.253 56.58 57.09 MRL 25.37 0.771 0.183 66.57 60.35

Budget Training

(Eq. (4)), sorting in ascending and descending order, as well as sorting criteria not determined by splat characteristics (Fig. 6). Sorting by opacity in descending order consistently produces the most effective multi-budget performance among all strategies: at 10% of the splat budget, it achieves 22.2dB PSNR at 493FPS, whereas the next-best score-based ordering (SH-energy descending) reaches only 17.6dB under the same constraints. Sorting in ascending order performs poorly overall, demonstrating worse performance than the descending variant.

We compare against two fixed insertion orders: append and prepend (cf . Sec. 3).

The two fixed insertion orders underperform opacity-descending at low prefix ratios: for example, at 10% budget, fixed-random reaches 21.5dB compared to 22.2dB for opacity-descending. This confirms the importance of a semantically meaningful coarse-to-fine ordering for preserving early-prefix quality, yielding 10.5dB and 11.5dB„ respectively, at the 10% of the splat budget.

Budget Training. Fixing our opacity-descending importance score, we compare three budget training strategies: prefix + full (our default; Eq. (7)), prefix only (no full-set term), and MRL nesting [20] (deterministic, fixed prefix sizes). The prefix + full achieves the best trade-off between low-budget and full-quality performance. Removing the full-set term (prefix only) improves early prefixes marginally but degrades quality at higher budgets. MRL nesting restricts the model to a discrete set of budget sizes, sacrificing the fine-grained coverage that stochastic sampling provides.

Prefix/Full Loss Weight. Sweeping the prefix:full weight ratio from 9:1 to 1:9 reveals a clear trade-off (Fig. 7). At the 10% prefix, prefix-heavy weighting (9:1) attains 22.2dB whereas the full-heavy setting (1:9) drops to 21.1dB. Conversely,

- at full quality, the 1:9 ratio achieves the best performance (PSNR 25.5dB and LPIPS 0.169), surpassing 9:1 by +0.2dB. For simplicity, we use 1:1 (5:5) as the

[Figure 7]

- Fig. 7: Ablations on Prefix/Full Loss Weight distribution. While prefix-heavy or fullheavy weighting can marginally improve their respective endpoints, a 6:4 ratio provides the best area under the curve. For the sake of simplicity and balanced performance, we utilise a 5:5 ratio for our MGS approach and for all other ablation experiments.

default setting, as it achieves comparable performance (25.4dB at full quality and 22.1dB at 10% prefix quality).

### 5 Conclusion

In this work, we present Matryoshka Gaussian Splatting (MGS), a continuous budget control framework for 3DGS models. By learning an ordered, prefixclosed set of Gaussian primitives, MGS allows rendering at arbitrary splat budgets by truncating the primitive set, producing a dense spectrum of quality–speed operating points. To train a single representation to perform well at every prefix length, we introduce a stochastic budget training strategy, which can be efficiently integrated into existing 3DGS pipelines without architectural changes. Experiments on four standard benchmarks demonstrate that MGS matches the full-capacity performance of 3DGS while enabling continuous LoD control from a single model. Extensive ablations further confirm the effectiveness of the proposed ordering strategy, training objective, and budget sampling designs. Our results suggest that nested primitive representations provide a promising direction for scalable neural scene representations. Future work could explore distance or view-dependent prefix selection, adaptive budget scheduling, and integration with streaming or device-aware rendering systems.

### Acknowledgements

This work was supported by a UKRI Future Leaders Fellowship [grant number G127262].

### References

- 1. Barron, J.T., Mildenhall, B., Verbin, D., Srinivasan, P.P., Hedman, P.: Mip-nerf 360: Unbounded anti-aliased neural radiance fields. In: CVPR. pp. 5470–5479

(2022)

- 2. Cai, H., Gan, C., Wang, T., Zhang, Z., Han, S.: Once-for-all: Train one network and specialize it for efficient deployment. In: ICLR (2020)
- 3. Chen, Y., Li, M., Wu, Q., Lin, W., Harandi, M., Cai, J.: Pcgs: Progressive compression of 3d gaussian splatting. In: AAAI (2026)
- 4. Cheng, Z., Sun, M., Liu, Y., Ge, Z., Tang, L., Xu, M., Li, Y., Pan, P.: Clod-gs: Continuous level-of-detail via 3d gaussian splatting. In: ICLR (2026)
- 5. Clark, J.H.: Hierarchical geometric models for visible surface algorithms. Communications of the ACM 19(10), 547–554 (1976)
- 6. Fan, Z., Wang, K., Wen, K., Zhu, Z., Xu, D., Wang, Z.: Lightgaussian: Unbounded 3d gaussian compression with 15x reduction and 200+ fps. In: NeurIPS. vol. 37, pp. 140138–140158 (2024)
- 7. Fang, G., Wang, B.: Mini-splatting: Representing scenes with a constrained number of gaussians. In: ECCV. pp. 165–181. Springer (2024)
- 8. Fridovich-Keil, S., Yu, A., Tancik, M., Chen, Q., Recht, B., Kanazawa, A.: Plenoxels: Radiance fields without neural networks. In: CVPR. pp. 5501–5510 (2022)
- 9. Funkhouser, T.A., Séquin, C.H.: Adaptive display algorithm for interactive frame rates during visualization of complex virtual environments. In: Proceedings of the 20th annual conference on Computer graphics and interactive techniques. pp. 247– 254 (1993)
- 10. Giegl, M., Wimmer, M.: Unpopping: Solving the image-space blend problem for smooth discrete lod transitions. Computer Graphics Forum 26(1), 46–49 (2007)
- 11. Hanson, A., Tu, A., Singla, V., Jayawardhana, M., Zwicker, M., Goldstein, T.: Pup 3d-gs: Principled uncertainty pruning for 3d gaussian splatting. In: CVPR. pp. 5949–5958 (2025)
- 12. Hedman, P., Philip, J., Price, T., Frahm, J.M., Drettakis, G., Brostow, G.: Deep blending for free-viewpoint image-based rendering. TOG 37(6), 1–15 (2018)
- 13. Hoppe, H.: Progressive meshes. In: SIGGRAPH. pp. 99–108 (1996)
- 14. Hoppe, H.: View-dependent refinement of progressive meshes. In: SIGGRAPH. pp. 189–198 (1997)
- 15. Kerbl, B., Kopanas, G., Leimkühler, T., Drettakis, G.: 3d gaussian splatting for real-time radiance field rendering. TOG 42(4), 139–1 (2023)
- 16. Kerbl, B., Meuleman, A., Kopanas, G., Wimmer, M., Lanvin, A., Drettakis, G.: A hierarchical 3d gaussian representation for real-time rendering of very large datasets. TOG 43(4), 1–15 (2024)
- 17. Kheradmand, S., Rebain, D., Sharma, G., Sun, W., Tseng, Y.C., Isack, H., Kar, A., Tagliasacchi, A., Yi, K.M.: 3d gaussian splatting as markov chain monte carlo. In: NeurIPS. vol. 37, pp. 80965–80986 (2024)
- 18. Knapitsch, A., Park, J., Zhou, Q.Y., Koltun, V.: Tanks and temples: Benchmarking large-scale scene reconstruction. TOG 36(4), 1–13 (2017)
- 19. Kulhanek, J., Rakotosaona, M.J., Manhardt, F., Tsalicoglou, C., Niemeyer, M., Sattler, T., Peng, S., Tombari, F.: Lodge: Level-of-detail large-scale gaussian splatting with efficient rendering. In: NeurIPS (2025)
- 20. Kusupati, A., Bhatt, G., Rege, A., Wallingford, M., Sinha, A., Ramanujan, V., Howard-Snyder, W., Chen, K., Kakade, S., Jain, P., et al.: Matryoshka representation learning. In: NeurIPS. vol. 35, pp. 30233–30249 (2022)

- 21. Lee, Y., Zhang, Z., Fan, D.: Safeguardgs: 3d gaussian primitive pruning while avoiding catastrophic scene destruction. In: WACV. pp. 8479–8489 (2026)
- 22. Liu, Y., Zhong, Z., Zhan, Y., Xu, S., Sun, X.: Maskgaussian: Adaptive 3d gaussian representation from probabilistic masks. In: CVPR. pp. 681–690 (2025)
- 23. Lu, T., Yu, M., Xu, L., Xiangli, Y., Wang, L., Lin, D., Dai, B.: Scaffold-gs: Structured 3d gaussians for view-adaptive rendering. In: CVPR. pp. 20654–20664 (2024)
- 24. Luebke, D., Reddy, M., Cohen, J.D., Varshney, A., Watson, B., Huebner, R.: Level of detail for 3D graphics. Elsevier (2002)
- 25. Mildenhall, B., Srinivasan, P.P., Tancik, M., Barron, J.T., Ramamoorthi, R., Ng, R.: Nerf: Representing scenes as neural radiance fields for view synthesis. In: ECCV. pp. 405–421 (2020)
- 26. Milef, N., Seyb, D., Keeler, T., Nguyen-Phuoc, T., Božič, A., Kondguli, S., Marshall, C.: Learning fast 3d gaussian splatting rendering using continuous level of detail. Computer Graphics Forum 44(2), e70069 (2025)
- 27. Navaneet, K., Pourahmadi Meibodi, K., Abbasi Koohpayegani, S., Pirsiavash, H.: Compgs: Smaller and faster gaussian splatting with vector quantization. In: ECCV. pp. 330–349. Springer (2024)
- 28. Neff, T., Stadlbauer, P., Parger, M., Kurz, A., Mueller, J.H., Chaitanya, C.R.A., Kaplanyan, A., Steinberger, M.: Donerf: Towards real-time rendering of compact neural radiance fields using depth oracle networks. Computer Graphics Forum 40(4), 45–59 (2021)
- 29. Papantonakis, P., Kopanas, G., Kerbl, B., Lanvin, A., Drettakis, G.: Reducing the memory footprint of 3d gaussian splatting. Proceedings of the ACM on Computer Graphics and Interactive Techniques 7(1), 1–17 (2024)
- 30. Reiser, C., Peng, S., Liao, Y., Geiger, A.: Kilonerf: Speeding up neural radiance fields with thousands of tiny mlps. In: ICCV. pp. 14315–14325 (2021)
- 31. Ren, K., Jiang, L., Lu, T., Yu, M., Xu, L., Ni, Z., Dai, B.: Octree-gs: Towards consistent real-time rendering with lod-structured 3d gaussians. TPAMI pp. 1–15

(2025)

- 32. Rippel, O., Gelbart, M., Adams, R.: Learning ordered representations with nested dropout. In: ICML. pp. 1746–1754. PMLR (2014)
- 33. Seo, Y., Choi, Y.S., Son, H.S., Uh, Y.: Flod: Integrating flexible level of detail into 3d gaussian splatting for customizable rendering. In: SIGGRAPH. pp. 1–16 (2025)
- 34. Shen, J., Qian, Y., Zhan, X.: Lod-gs: Achieving levels of detail using scalable gaussian soup. In: CVPR. pp. 671–680 (2025)
- 35. Shi, Y., Morin, G., Gasparini, S., Ooi, W.T.: Lapisgs: Layered progressive 3d gaussian splatting for adaptive streaming. In: 3DV. pp. 991–1000. IEEE (2025)
- 36. Tian, B., Gao, Q., Xianyu, S., Cui, X., Zhang, M.: Flexgaussian: Flexible and cost-effective training-free compression for 3d gaussian splatting. In: ACM MM. pp. 7287–7296 (2025)
- 37. Wang, L., Shi, X., Liu, Y.: Foveated rendering: A state-of-the-art survey. Computational Visual Media 9(2), 195–228 (2023)
- 38. Wang, Z., Bovik, A.C., Sheikh, H.R., Simoncelli, E.P.: Image quality assessment: from error visibility to structural similarity. TIP 13(4), 600–612 (2004)
- 39. Xiangli, Y., Xu, L., Pan, X., Zhao, N., Rao, A., Theobalt, C., Dai, B., Lin, D.: Bungeenerf: Progressive neural radiance field for extreme multi-scale scene rendering. In: ECCV. pp. 106–122. Springer (2022)
- 40. Yan, Z., Low, W.F., Chen, Y., Lee, G.H.: Multi-scale 3d gaussian splatting for anti-aliased rendering. In: CVPR. pp. 20923–20931 (2024)

- 41. Ye, V., Li, R., Kerr, J., Turkulainen, M., Yi, B., Pan, Z., Seiskari, O., Ye, J., Hu, J., Tancik, M., et al.: gsplat: An open-source library for gaussian splatting. Journal of Machine Learning Research 26(34), 1–17 (2025)
- 42. Yu, J., Yang, L., Xu, N., Yang, J., Huang, T.: Slimmable neural networks. In: ICLR

(2019)

- 43. Yu, Z., Chen, A., Huang, B., Sattler, T., Geiger, A.: Mip-splatting: Alias-free 3d gaussian splatting. In: CVPR. pp. 19447–19456 (2024)
- 44. Zhang, R., Isola, P., Efros, A.A., Shechtman, E., Wang, O.: The unreasonable effectiveness of deep features as a perceptual metric. In: CVPR. pp. 586–595 (2018)
- 45. Zhang, Y., Ortín-Obón, M., Arellano, V., Wang, R., Gutierrez, D., Bao, H.: Onthe-fly power-aware rendering. Computer Graphics Forum 37 (2018)

