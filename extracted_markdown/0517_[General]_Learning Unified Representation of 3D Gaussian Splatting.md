<!-- page 1 -->
Published as a conference paper at ICLR 2026
LEARNING UNIFIED REPRESENTATION OF
3D GAUSSIAN SPLATTING
Yuelin Xin1
Yuheng Liu1
Xiaohui Xie1
Xinke Li2,†
1UC Irvine
2City University of Hong Kong
ABSTRACT
A well-designed vectorized representation is crucial for the learning systems na-
tively based on 3D Gaussian Splatting. While 3DGS enables efficient and explicit
3D reconstruction, its parameter-based representation remains hard to learn as fea-
tures, especially for neural-network-based models. Directly feeding raw Gaussian
parameters into learning frameworks fails to address the non-unique and hetero-
geneous nature of the Gaussian parameterization, yielding highly data-dependent
models. This challenge motivates us to explore a more principled approach to
represent 3D Gaussian Splatting in neural networks that preserves the underly-
ing color and geometric structure while enforcing unique mapping and channel
homogeneity. In this paper, we propose an embedding representation of 3DGS
based on continuous submanifold fields that encapsulate the intrinsic information
of Gaussian primitives, thereby benefiting the learning of 3DGS. Implementation
available at https://github.com/cilix-ai/gs-embedding.
1
INTRODUCTION
Recent advances in 3D Gaussian Splatting (3DGS) (Kerbl et al., 2023) have established it as a
powerful technique for representing and rendering 3D scenes, enabling high-fidelity, real-time novel
view synthesis through explicit parameterization of Gaussian primitives. This representation has cat-
alyzed a growing body of work exploring learning-based methods that operate directly on Gaussian
primitives, supporting tasks such as compression (Shin et al., 2025), generation (Yi et al., 2024; Xie
et al., 2025), and understanding (Guo et al., 2024). In these pipelines, the native parameterization
θ = {µ, q, s, c, o} is often adopted as the input or output of neural architectures.
Despite its effectiveness in optimization-based reconstruction, we identify fundamental limitations
when this parametric representation is employed as a learning space for neural networks. Specifi-
cally, the native parameterization θ conflicts with the inductive biases of standard neural architec-
tures in three critical ways. First, the mapping from parameters to rendered output exhibits non-
uniqueness. Ambiguities such as quaternion sign duality and symmetry-induced variances create a
one-to-many mapping. This mapping creates “embedding collisions” where distinct parameter in-
puts producing identical visual outputs generate conflicting supervision signals, leading to training
instability and poor convergence (Bengio et al., 2013; Wang & Isola, 2020). Second, the parameter
components suffer from numerical heterogeneity. Spatial positions span large magnitudes while
quaternions remain unit-normalized, violating the homogeneous feature distribution assumption re-
quired for effective gradient flow (Ioffe & Szegedy, 2015). Third, these parameters inherently reside
on distinct mathematical manifolds, such as positions in R3, rotations in SO(3), and appearance
in spherical harmonic coefficients. Forcing these non-Euclidean variables into the Euclidean feature
spaces of standard encoders breaks their intrinsic geometric structure, making the representation
difficult to compress or regularize effectively.
These theoretical misalignments translate into substantial practical failures across various applica-
tions. Our empirical analysis reveals that parametric encoders are critically unstable; for instance,
due to the sign ambiguity, simply negating a quaternion (a mathematically equivalent rotation) can
cause complete decoding failure in parameter-trained autoencoders, see App. Fig. 9. This instability
extends to generative tasks involving latent manipulation, where we observe that linear interpolation
† Corresponding author.
1
arXiv:2509.22917v2  [cs.CV]  30 Jan 2026

<!-- page 2 -->
Published as a conference paper at ICLR 2026
Iso-Probability Surface
Latent Space - 
Parametric Representation
Parameters Embedding
Submanifold Field Embedding (Ours)
Figure 1: A scene of N Gaussian primitives can be represented by N sets of parameters θ (shown
in pink). Data in this parametric space resides on different manifolds and is heterogeneous and non-
Euclidean, introducing challenges for encoders to fit disparate data manifolds implicitly. Shown in
purple is the proposed representation, instead of relying on Gaussian parameterization, we introduce
a canonical submanifold field space (M, F) that uniquely represents a Gaussian primitive with an
iso-probability surface.
in the parametric latent space results in geometric “jitters” and unnatural transitions. Furthermore,
parametric embeddings lack robustness to noise, with minor perturbations causing disproportionate
reconstruction errors. Crucially, for downstream tasks extensively explored in recent work includ-
ing generative modeling (Yi et al., 2024; Zhou et al., 2024b), compression (Shin et al., 2025; Girish
et al., 2024), and editing (Chen et al., 2024a), these flaws manifest as discontinuous latent spaces and
inefficient encoding. Instead of capturing robust geometric semantics, models are forced to resolve
parameter ambiguities with more efforts, leading to sub-optimal performance in learning-based re-
construction (Charatan et al., 2024) and limited generalization across diverse domains.
We thus propose a principled alternative that represents each Gaussian primitive as a continuous field
defined on its iso-probability surface. This submanifold field representation establishes a unique
correspondence between Gaussians and their geometric-photometric properties, removing the am-
biguities of parametric representations. By discretizing this field as a colored point cloud sampled
from the probability surface, we obtain a numerically uniform and geometrically consistent repre-
sentation. We further employ a variational autoencoder to learn embeddings from these discretized
submanifold fields, together with a Manifold Distance metric based on optimal transport that bet-
ter correlates with perceptual quality than parameter-space distances. Extensive experiments show
higher reconstruction quality, stronger cross-domain generalization, and more robust latent repre-
sentations. The learned embedding space is smooth and generalizable, indicating strong potential
for semantic understanding and generative modeling, as demonstrated through unsupervised seg-
mentation and neural field decoding with the proposed embeddings. To summarize the contribution
of this work, we:
• identify and formally characterize the fundamental limitations of parametric Gaussian rep-
resentations for neural learning, including non-uniqueness and numerical heterogeneity.
• propose a submanifold field representation that provides provably unique and geometrically
consistent encoding of Gaussian primitives.
• develop a variational autoencoder framework incorporating a novel Manifold Distance met-
ric based on optimal transport theory for effective learning in the submanifold field repre-
sentation space with extensive experimental evidence.
2
RELATED WORKS
3D Gaussian Splatting. Since its re-introduction by Kerbl et al. (2023), 3DGS has rapidly become a
core method for novel view synthesis and 3D representation. By placing explicit Gaussian primitives
in 3D space and employing efficient rasterization and accumulation, 3DGS achieves real-time ren-
dering with high fidelity (Bao et al., 2025; Lin et al., 2025c). Several studies improve efficiency (Jo
2

<!-- page 3 -->
Published as a conference paper at ICLR 2026
et al., 2024; Lee et al., 2024), while others leverage large-scale datasets for generalization (Ma et al.,
2025; Li et al., 2025a). At the application level, 3DGS has been adopted for digital human (Li et al.,
2024; Kocabas et al., 2024; Wang et al., 2025), self-driving scene modeling (Zhou et al., 2024a;c;
Yan et al., 2023), and physics-based simulation (Jiang et al., 2024; Xie et al., 2024; Zhong et al.,
2024). Beyond fixed Gaussian parameters, another line augments primitives with latent embeddings
to capture semantics, open-vocabulary understanding (Qin et al., 2024) and deformation model-
ing (Zhobro et al., 2025). These efforts demonstrate that 3DGS provides high-fidelity appearance
and serves as a versatile representation with broad potential (Sun et al., 2025).
3DGS Parameters Regression. To enable fast and flexible reconstruction without per-scene op-
timization, recent works seek to directly obtain Gaussian splats through feedforward prediction
networks. For example, Charatan et al. (2024); Chen et al. (2024b) proposed to predict Gaussian
parameters directly from multi-view input, while Zheng et al. (2024) generate pixel-wise parame-
ter maps and lift them to 3D via depth estimation. This paradigm has been extended to pose-free
settings (Hong et al., 2024; Chen et al., 2024c; Tian et al., 2025), and transformer-based methods
further improve scalability and generalization (Li et al., 2025b; Jiang et al., 2025; Lin et al., 2025b).
Overall, these methods directly output Gaussian parameters from neural networks, showing that
3DGS can serve as an effective target for network-based prediction in efficient reconstruction.
Embedding Gaussian Primitives. Recent works move beyond reconstruction and encode Gaussian
parameters into latent spaces for tasks such as generation, editing, and compression.
Zhou et al.
(2024b); Lin et al. (2025a); Wewer et al. (2024) learn structured latent variables from 3D Gaussian
space to fulfill generation tasks. Editing and style-transfer methods use diffusion or style condition-
ing to manipulate Gaussians primitives in latent or rendering spaces (Chen et al., 2024a; Vachha &
Haque, 2024; Lee et al., 2025; Palandra et al., 2024; Zhang et al., 2024; Kov´acs et al., 2024; Yu et al.,
2024). Other works improve rendering quality by optimizing Gaussian parameters under diffusion
priors (Tang et al., 2023; Yi et al., 2024; Chen et al., 2024d), while compression methods (Girish
et al., 2024; Yang et al., 2025) reduce storage and computation by quantizing and embedding Gaus-
sian parameters. These approaches show the potential of embedding Gaussians into neural latent
spaces, but they assume Gaussian parameters are naturally compatible with neural learning, over-
looking that these parameters were designed for optimization-based reconstruction. This oversight
underlies our analysis in Section 3 and our proposal of a more suitable formulation.
3
METHOD
3.1
PRELIMINARIES: GAUSSIAN SPLATTING PARAMETERIZATION
A scene under 3D Gaussian Splatting is represented as a set of N oriented, and view-dependently
colored Gaussian primitives {Gi}N
i=1, each contributing to the final rendered image via rasterization
and alpha compositing. Each Gaussian primitive Gi is usually represented by a parameter tuple
θi = {µi, qi, si, ci, oi}, where:
• µi ∈R3: the center position of the Gaussian in world coordinates;
• qi ∈SO(3): a unit quaternion representing the local rotation;
• si ∈(R+)3: scale parameters along the rotated axes;
• ci ∈R3×K: spherical harmonic (SH) coefficients for view-dependent color for K ∈Z;
• oi ∈R: a logit-transformed opacity value αi = σ(oi), where σ is a sigmoid function.
The local geometry of the Gaussian is governed by its covariance matrix, constructed as
Σi = R(qi) diag(si)2 R(qi)⊤,
(1)
where R(qi) is the rotation matrix corresponding to the quaternion qi. This defines an ellipsoidal
spatial density, centered at µi, whose shape and orientation determine the contribution of Gi to the
rendered scene. The color at a given view direction d ∈S2 is computed per channel using SH basis
functions denoted by
Colori(d) =
h
SHr
i (d), SHg
i (d), SHb
i(d)
i⊤
,
(2)
3

<!-- page 4 -->
Published as a conference paper at ICLR 2026
where SHc
i(d) in c−channel is calculated by PLmax
l=0
Pl
m=−l(ci)c,(l,m) · Y m
l (d) Y m
l
is the real-
valued spherical harmonic of degree l and order m. The final rendering aggregates contributions
from all Gi via a soft visibility-weighted compositing process. This native parameterization is well-
suited for gradient-based scene optimization. However, it introduces significant challenges when
used as a representation for learning.
3.2
PARAMETERIZATION IS ILL-SUITED AS A LEARNING SPACE
The parameter representation θ poses fundamental challenges when used as a learning space for
neural networks. We identify two critical issues: representation non-uniqueness and numerical het-
erogeneity. Each undermines the stability and effectiveness of neural network training.
Representation Non-uniqueness. The parametric representation suffers from a many-to-one map-
ping that violates basic requirements for stable learning. To understand this, we first formalize what
rendering effect a single Gaussian primitive produces.
Definition 1 (Single Gaussian Radiance Field (SGRF)) A SGRF is a radiance field ϕ : R3×S2 →
R3, The field is defined by the local density at point x ∈R3 along direction d ∈S2:
ϕG(x, d) = ρG(x) · cG(d),
(3)
where ρG(x) = exp
 −1
2(x −µ)⊤Σ−1(x −µ)

is a volume density function and cG(d) is a color
radiance field coupled with opacity. Specifically, given a parameter set θ = {µ, q, s, c, o}, Σ can
be derived by equation 1 and cG(d) = σ(o) · Color(d) can be derived by equation 2.
The SGRF, derived from the multi-Gaussian rendering framework by Kerbl et al. (2023), specifies
how the final value at any pixel is rendered in a scene containing only one Gaussian splat. Further-
more, let Φ be the space of SGRFs, and Θ ⊆R|θ| be the paramater space of Gaussian primitives,
each parameter set θ ∈Θ provides a complete representation that generates a correponding field
ϕG ∈Φ. We indicate that a single SGRF may correspond to multiple parameterizations of Gaussian
primitives, as formalized in the following proposition.
Proposition 1 (Non-uniqueness of the SGRF Parametric Representation) The parametric rep-
resentation of a SGRF is not unique. Formally, there exist at least two distinct parameter sets,
θ1 ∈Θ and θ2 ∈Θ with θ1 ̸= θ2, that generate the exact same field ϕG ∈Φ.
The non-uniqueness is from quaternion sign ambiguity, geometric symmetries, and rotation-
spherical harmonic interactions producing equivalent parameter combinations (see App.
A for
proof). The non-uniqueness of θ will create “embedding collisions” where different parameter
vectors produce identical rendered output (Wang & Isola, 2020). This makes the learning objec-
tive ∥θpred −θtarget∥p ambiguous, as multiple parameter configurations can achieve the same visual
result. The resulting conflicting gradients lead to training instability and poor convergence indicated
by Bengio et al. (2013).
Numerical Heterogeneity The parameter components violate the homogeneous distribution as-
sumption of standard neural architectures. Neural networks typically assume features share similar
statistical properties for effective gradient flow (Ioffe & Szegedy, 2015). However, 3D Gaussian
parameters span vastly different ranges. For example, pre-activation scales can range from −15
to 3, while quaternions stay unit-normalized. More fundamentally, these parameters follow differ-
ent distributions and live on different manifolds: positions µ ∈R3, rotations q ∈SO(3), scales
s ∈(R+)3, and SH coefficients c with exponential decay. Concatenating them ignores their het-
erogeneous nature. Small noises in quaternions can drastically alter geometry, while small noise in
high-order SH coefficients is negligible, yet the network treats all dimensions equally.
The non-uniqueness and numerical heterogeneity of the native parameter space θ make it unsuitable
for neural network learning, which would generate unstable embeddings (see our experiments in
Sec. 4.3 and App. D). We therefore introduce a submanifold field representation that ensures unique
mappings and respects the geometric structure of 3D Gaussians.
4

<!-- page 5 -->
Published as a conference paper at ICLR 2026
Manifold  Sampling
Submanifold Field Variational Auto-Encoder
Embedding
Unit Sphere
Parameter Fitting
PCA
SH
Coordinates Transform
Color Field
...
...
...
...
Repeat
Repeat
Figure 2: To embed the proposed submanifold field representation into a vector form suitable for
neural networks, we devise a Submanifold Field Variational Auto-encoder (SF-VAE) that embeds
any input submanifold field as a 32-D vector, then reconstructs the original parameter set θi. SF-
VAE learns in our new representation space instead of the parametric space.
3.3
REPRESENTATION ON SUBMANIFOLD FIELD
To address this issue, we propose converting each Gaussian primitive Gi to a novel geometric repre-
sentation Ei, which is a color field defined on a 2D submanifold in 3D Euclidean space, as illustrated
in Fig. 1. For a Gaussian density N(x; µi, Σi), we define the iso-probability surface at fixed radius
r as:
Mi =

x ∈R3 | (x −µi)⊤Σ−1
i (x −µi) = r2	
,
(4)
which forms an ellipsoid surface, namely, a two-dimensional submanifold, centered at µi. On this
submanifold, we define a field function:
Fi(x) = σ(oi) · Colori(dx),
(5)
where dx = (x −µi)/∥x −µi∥denotes the unit direction vector for x ∈Mi, and Colori(·)
represents the view-dependent color parameterization as in equation 2. Let M be the space of all
possible iso-probability submanifolds as defined in equation 4, we define our unified representation
space as:
E =

Ei = (Mi, Fi) | Mi ∈M, Fi : Mi →R3	
,
(6)
The representation Ei ∈E encodes both geometric properties (shape, orientation) via Mi and ap-
pearance attributes (view-dependent color) via Fi in a continuous framework. We have the following
proposition (proof is provided in App. B).
Proposition 2 (Uniqueness of Submanifold Field Representation) For every SGRF ϕG
∈Φ,
there exists a unique corresponding representation E ∈E . This establishes a one-to-one corre-
spondence between the elements of Φ and E . Formally, for any two distinct fields ϕG,1, ϕG,2 ∈Φ,
their corresponding representations E1, E2 ∈E are also distinct.
The submanifold field Ei thus provides a numerically stable and provably unique representation
space on which we can safely build learning objectives and neural architectures.
3.4
ENCODE SUBMANIFOLD FIELDS AS EMBEDDINGS
We design a variational auto-encoder to encode submanifold field representation, shown in Fig. 2.
The network architecture, learning objectives and dataset are introduced.
Encoder-decoder Architecture. We employ a point-cloud-based network to encode and decode
one sub-manifold field. Particularly, we uniformly sample P points from the submanifold field E
as a colored point cloud P =

(xm, F(dxm))
	P
m=1. We then employ a PointNet (Qi et al., 2017)
encoder f to obtain latent embedding by z ∼f(z | P) where z ∈RD is the embedding with
dimension D. The decoder g consists of two neural networks, namely, the coordinates transform
network gc : R3 × RD →R3 and color field gf : R3 × RD →R3. The decoded point cloud from
decoder is given by,
ˆP = g(z, UP ′) = {gc([en, z]), gf([gc([en, z]), z])}P ′
n=1
(7)
5

<!-- page 6 -->
Published as a conference paper at ICLR 2026
where UP ′ = {en}P ′
n=1 is a set of coordinates sampled from a unit sphere surface. Such canonical
set works as the initial input for two implicit functions gc and gf, and queries new coordinates and
color field. Furthermore, to recover the original Gaussian parameters θi for rendering purposes, we
estimate the covariance matrix Σi by principal component analysis (PCA), and SH coefficients ci
by fitting the spherical harmonics to ˆP.
Learning Objectives. We introduce Manifold Distance (M-Dist) for the reconstruction objective in
encoder-decoder training. Given two submanifold fields E = (M, F) and ˆE = ( ˆ
M, ˆF), we propose
to measure their similarity based on the Wasserstein-2 distance from optimal transport defined as
W 2
2 (E, ˆE) =
inf
γ∈Γ(ˆσ,ˆσ′)
Z
M× ˆ
M
d2 (x, cx), (y, cy)

dγ(x, y)
(8)
where cx = F(dx), cy = ˆF(dy), Γ(ˆσi, ˆσj) is the set of all joint probability measures (transport
plans) with marginals ˆσi and ˆσj, and the ground distance is defined as
d2 (x, cx), (y, cy)

= ∥x −y∥2
2 + λ∥cx −cy∥2
2,
(9)
with λ ∈R+ balancing spatial and color terms. In practice, both M and
ˆ
M are discretized as
colored point clouds P and ˆP. The empirical Wasserstein-2 distance ˆW is then computed between
these point clouds by
ˆW 2
2 (P, ˆP) =
min
Γ∈Γ(ˆσ,ˆσ′)
X
(xi,cxi)∈P
X
(yj,cyj )∈ˆ
P
Γij
 d2 (xi, cxi), (yj, cyj)

.
(10)
Finally, the learning objective for variational auto-encoder is
LVAE = E ˆ
P∼VAE(P)

ˆW 2
2 (P, ˆP) + β · dKL (f(z | P)∥N(0, I))

,
(11)
where VAE(P) = g(f(z | P), UP ′) and the second term is the KL divergence loss for variational
auto-encoder implementation, and β is a balance factor.
Dataset Preparation. Since this embedding model only encodes single Gaussian primitives, which
have no semantic meaning out of a scene’s global context, we can use a randomly generated dataset
of Gaussian primitives to train this model, thus making it domain-invariant to data. The implemen-
tation details of this generated dataset can be found in App. C.
4
EXPERIMENTS
4.1
EVALUATION SETUP
Baseline Implementation Details. To isolate the effect of representation choice, we adopt a self-
implemented encoder–decoder framework for both the parametric representation θ and the proposed
submanifold field representation E. While comparisons with existing 3DGS learning methods are
possible, they typically involve task-specific architectures that confound the role of representation
itself. Direct reuse of prior pipelines would not yield a controlled comparison, so we implement
both baselines in the same VAE-style framework to attribute differences solely to the representation.
We implement and train three size-matched embedding models:
our submanifold field VAE
(Sec. 3.4), and two baseline parametric VAEs operating directly on θ. For the parametric mod-
els, each Gaussian primitive is represented as a 56-D vector (3+4+3K+1 for Lmax=3), omitting
global coordinates to match the SF-VAE setting. A three-layer MLP encodes this input to a 32-D
latent (56→512→512→32 × 2), and the decoder, either uses a MLP to map the latent back to bθi,
or uses the same decoder of SF-VAE to map to ˆP. This setting further decouples evaluation results
with the training objective functions. Apart from input dimension, all models share identical depth,
width, latent size (32), and optimizer settings (all using Adam), ensuring a matched capacity.
Datasets. We evaluate the proposed representation and compare it with the baseline primarily using
two datasets. For object-level tasks, we utilize ShapeSplat (Ma et al., 2025), a large-scale 3DGS
dataset derived from ShapeNet (Chang et al., 2015), comprising 52K objects across 55 categories.
For scene-level experiments, we employ Mip-NeRF 360 (Barron et al., 2022), which contains 7
6

<!-- page 7 -->
Published as a conference paper at ICLR 2026
Table 1: Reconstruction quality comparison for object-level (ShapeSplat) and scene-level (Mip-
NeRF 360) datasets. All models trained on the randomly generated dataset. The three models have
a parameter count of 0.62M, 0.66M and 0.62M respectively. The relatively extreme perceptual
metrics values in ShapeSplat come from the use of background during measurement.
Input Representation
Encoder
Decoder
PSNR ↑
SSIM ↑
LPIPS↓
M-Dist
L1-Dist
ShapeSplat
Parametric
MLP
MLP
37.512
0.888
0.152
0.184
0.040
Parametric
MLP
SF-VAE
44.725
0.896
0.136
0.051
0.097
Submanifold Field
SF-VAE
SF-VAE
63.408
0.990
0.010
0.041
0.098
Mip-NeRF 360
Parametric
MLP
MLP
18.818
0.564
0.452
0.510
0.034
Parametric
MLP
SF-VAE
20.923
0.730
0.359
0.055
0.173
Submanifold Field
SF-VAE
SF-VAE
29.833
0.953
0.079
0.048
0.179
Table 2: Reconstruction quality comparison under cross-domain setting. All models trained on either
ShapeSplat or Mip-NeRF 360 dataset are tested on another dataset. We show that the generalization
ability of SF Embedding framework is inherently domain-agnostic even without random data.
Train set
Test set
Input Represent.
Encoder / Decoder
PSNR ↑
SSIM ↑
LPIPS ↓
ShapeSplat
Mip-NeRF.
Parametric
MLP / MLP
9.753
0.356
0.615
Parametric
MLP / SF-VAE
14.845
0.675
0.336
Submanifold Field
SF-VAE / SF-VAE
19.194
0.821
0.309
Mip-NeRF.
ShapeSplat
Parametric
MLP / MLP
55.624
0.957
0.067
Parametric
MLP / SF-VAE
60.777
0.987
0.013
Submanifold Field
SF-VAE / SF-VAE
62.576
0.990
0.014
medium-scale scenes with abundant high-frequency details. Additionally, unless stated otherwise,
we train the embedding models using the randomly generated Gaussian primitive dataset, with 500K
randomly generated data samples; implementation details are provided in App. C.
Evaluation Metrics. To comprehensively assess both perceptual fidelity and representation qual-
ity, we report PSNR, SSIM, and LPIPS on rasterized reconstructions against ground truth Gaussian
splats, as well as L1 distance in the Gaussian parameter space. Crucially, we also include our
proposed Manifold Distance (M-Dist) as an evaluation criterion. By cross-comparing M-Dist with
parameter-space distances (L1/L2), we can demonstrate that M-Dist aligns more closely with per-
ceptual “gold standard” metrics such as PSNR and LPIPS, validating our claims in Sec. 3
4.2
EVALUATION ON REPRESENTATION LEARNING FRAMEWORK
Zero-shot Reconstruction. We present a comprehensive quantitative and qualitative analysis of
reconstruction quality for both object-level and scene-level data, as summarized in Tab. 1 and Fig. 3.
All models are trained on the same randomly generated 3D Gaussian primitives dataset and evaluated
on ShapeSplat and Mip-NeRF 360, using three matched encoder-decoder configurations to control
for bias. Across all perceptual metrics (PSNR, SSIM, LPIPS), the submanifold field representation
consistently outperforms parametric baselines. For example, on ShapeSplat, SF-VAE achieves sub-
stantially higher PSNR and SSIM and a much lower LPIPS, indicating both improved fidelity and
perceptual quality. Similar performance gains are observed in scene-level reconstruction, where the
submanifold field model demonstrates better performance across diverse spatial contexts.
Importantly, the Manifold Distance (M-Dist) metric shows a stronger empirical correlation with
quality metrics like PSNR and LPIPS than traditional L1 parameter distances, supporting our claim
that M-Dist is a more robust and meaningful similarity measure for 3D Gaussian representations,
truthfully reflecting perceptual differences rather than merely parameter discrepancies. The consis-
tent improvement margin across both datasets highlights the advantage of learning in the submani-
fold field space, which better preserves intrinsic structure and view-dependent appearance, confirm-
ing the efficacy of our representation for high-fidelity 3D Gaussian modeling.
7

<!-- page 8 -->
Published as a conference paper at ICLR 2026
Ground Truth
MLP / MLP
SF-VAE
Ground Truth
MLP / SF-VAE
SF-VAE
MLP / SF-VAE
MLP / MLP
Figure 3: Qualitative results for rasterized reconstruction. Samples selected arbitrarily from Mip-
NeRF 360 and ShapeSplat. Parametric models can induce confusion in parameter space, failing to
embed and restore the correct Gaussian parameters.
Noise Level = 0
Noise Level = 0.1
Noise Level = 0.3
Noise Level = 0.5
SF Emb.
Parametric Emb.
0
0.05
0.1
0.15
0.2
0
0.1
0.2
0.3
0.4
0.5
M-Dist
Noise Level
Add Noise to Embedding
Parametric Emb.
SF Emb.
Figure 4: Reconstruction results using embeddings with noise. Left: Visualization of reconstructed
scene from noisy embeddings of Gaussian parameters (MLP) and SF-VAE. Right: Comparison on
M-Dist for different noise levels added to embedding space, tested on Mip-NeRF 360. Noise level
is defined as the ratio between the noise magnitude and the embedding variance.
Cross-domain Reconstruction. We also evaluate cross-domain generalization by training on one
real-world dataset and testing on the other (object-level ↔scene-level) under an identical training
protocol and capacity budget as in the reconstruction study. Concretely, we train either the proposed
SF-VAE or the parametric MLP baselines on a source set and evaluate on a target set, rendering
novel views and reporting PSNR, SSIM, and LPIPS averaged over test samples (see Tab. 2). Across
both transfer directions, the SF-based embedding consistently achieves higher reconstruction quality
than the parametric baseline, indicating reduced sensitivity to domain-specific statistics (e.g., scale,
lighting, SH complexity). Particularly, comparing these transfer results with Tab. 1, we find that
the model trained on synthetic random data actually outperforms the models transferred from real-
world domains. This indicates that our random learning strategy effectively strips away domain
priors, which establishes our approach as a unified representation, where a single model trained on
synthetic data can fundamentally generalize to real-world contexts.
4.3
SENSITIVITY STUDY OF REPRESENTATION
Robustness to Noise. To evaluate the submanifold field embedding’s robustness to noise, we grad-
ually add higher levels of gaussian noise to the embedding space of the parametric model and the
submanifold field model and test their reconstruction quality and M-Dist. To ensure fair compar-
ison, we use noise level as a ratio to variance instead of absolute noise magnitude. As shown in
Fig. 4, the embedding space of submanifold field model is more robust to random perturbation, this
makes submanifold field embeddings a better learning target since it is less sensitive to potential
noise introduced by downstream regression.
8

<!-- page 9 -->
Published as a conference paper at ICLR 2026
Reference Image
MLP / MLP
Parameters
MLP / SF-VAE
SF-VAE
Figure 5: Unsupervised graph clustering based on raw Gaussian parameters and various embed-
dings. Submanifold field embeddings show better preservation of detailed semantics, showing its
downstream applicability.
Latent Space Interpolation. To evaluate the regularity of the latent space of the proposed repre-
sentation, we randomly sample pairs of source and target Gaussian primitives Gs and Gt and linearly
interpolate each pair for a fixed number of steps n = 7. Compared with parametric space, the inter-
polation in submanifold field embedding space shows a smooth transition path, while interpolation
in parametric space shows undesired jitter in rotation and scale, indicating space irregularities, see
App. D. This highlights the motivation to learn in the unified submanifold field embedding space.
4.4
REPRESENTATION APPLICABILITY
Unsupervised Clustering. To further probe the semantic structure of the learned embedding spaces,
we perform unsupervised graph clustering on both the raw Gaussian parameter space and the em-
bedding outputs of each model. As visualized in Fig. 5, clusters formed in the submanifold field
embedding space exhibit more detailed semantic separation against the reference images compared
to those formed using normalized parameters or parametric embeddings. For example, SF-VAE’s
embedding clustering in the first line of Fig. 5 outlines clearer separation of foreground objects with
the background. The clusters appear smoother, less noisy, and with clearer boundaries, showing an
ability to distinguish between different entities. This indicates that the submanifold field embedding
captures more dense semantics and discriminative features, validating its usefulness.
Gaussian Neural Fields. To validate the potential of our representation for advanced downstream
tasks, we introduce the Gaussian Neural Field (GNF). Drawing inspiration from the decoding struc-
tures in generative diffusion models (e.g., DiffGS by Zhou et al. (2024b)) and neural compression
frameworks (Wu & Tuytelaars, 2024), the GNF functions as a coordinate-based neural implicit field
as illustrated in Fig. 6. Specifically, it employs a lightweight MLP (architecture detailed in App.
D.4) to learn a continuous mapping from spatial coordinates xi to per-primitive descriptors. This
setup allows us to evaluate the “learnability” of our representation: while regressing heterogeneous
raw parameters θi often leads to optimization difficulties, our unified SF embeddings provide a
smooth and well-conditioned target for the neural field. As evidenced in Tab. 3 and visualization
in App. D.4, the SF-guided GNF outperforms the parameter-based baseline in visual fidelity with
equivalent training effort. This indicates that our representation is more friendly to neural networks,
hinting at its utility for potential downstream generative and compression tasks.
4.5
MORE STUDIES ON IMPLEMENTATION DETAILS
Ablation Study on SF-VAE Designs. We provide performance comparison with different frame-
work designs based on Mip-NeRF 360. (1) For encoder f, we tested DGCNN encoder (Wang et al.,
2019) beyond our implementation, where the DGCNN encoder achieves comparable reconstruction
fidelity while it is roughly 1.75× slower in encoding and uses roughly 2× more GPU memory during
inference; (2) For the decoder’s unit sphere grid, we tested a 2D grid implementation with matching
grid size, 2D grid achieves similar reconstruction results but takes more iterations to converge; (3)
We implemented two versions of the fitting module: a GPU-based version using FP32 with batching
9

<!-- page 10 -->
Published as a conference paper at ICLR 2026
Emb / GS Parameters
Figure 6: Setting of a Gaussian
Neural Field, we compare be-
tween the prediction target SF
embedding and raw GS param-
eters.
Table 3: Comparison between Gaussian Neural Fields trained
using submanifold field embeddings and raw Gaussian parame-
ters. Top: ShapeSplat, bottom: Mip-NeRF 360.
Target
PSNR ↑
SSIM ↑
LPIPS ↓
# Params
Raw GS Parameter
51.660
0.925
0.141
0.21M
SF Embedding
58.619
0.980
0.043
0.20M
Raw GS Parameter
19.922
0.648
0.410
1.87M
SF Embedding
24.395
0.804
0.261
1.85M
0
0.2
0.4
0.6
0.8
1
10
15
20
25
30
5k
10k
50k
100k
500k
PSNR (dB)
Training Samples
(b)
PSNR
SSIM
LPIPS
0
0.2
0.4
0.6
0.8
1
21
24
27
30
8
16
32
64
128
PSNR (dB)
Embedding Size
(a)
PSNR
SSIM
LPIPS
SSIM / LPIPS
SSIM / LPIPS
0
0.2
0.4
0.6
0.8
1
15
20
25
30
6
8
12
24
PSNR (dB)
Grid Size
(c)
PSNR
SSIM
LPIPS
SSIM / LPIPS
Figure 7: Behavior studies tested on Mip-NeRF 360. From left to right: (a) embedding dimension,
(b) generated training dataset size, (c) Submanifold Field discretized (i.e., point sample) grid size.
and Cholesky decomposition, and a CPU-based one using FP64 without batching and Least Squares
solver. Experiments show that the GPU version introduces only negligible quality degradation (0.4
PSNR and 0.01 SSIM), while achieving an average speedup of 85× with a batch size of 4096.
Behavior Study of Latent Space Dimension. We evaluated different embedding space dimensions
for the SF-VAE model to meet the best trade-off between compression and reconstruction quality.
All models are trained on the generated dataset with L = 3 order Spherical Harmonics. Results
shown in Fig. 7 (a), 32 is the optimal balance point between reconstruction quality and latent space
compression. All values are tested with baseline input/output of P = 122. While this work does
not specifically focus on compression effectiveness, embedding space robustness shown in Sec. 4.3
suggests potential in further latent tokenization and quantization.
Behavior Study of Training Set Size. To determine the number of random training samples re-
quired to achieve the best reconstruction results, we vary the trainiing sample size from 5K to 500K
(baseline), see Fig. 7 (b). The results indicate the proposed representation is data efficient. When
only using 2% of the baseline training sample, our model can achieve close-to-baseline performance.
Behavior Study of SF Discretized Size. To ensure the submanifold fields are truthfully represented
in a discrete manner, we evaluate different sample sizes P, see Fig. 7 (c). Going from the lowest
tested P = 62 to the baseline P = 122, we observe a gradual improvement in reconstruction
quality, while going above P = 122 yields very little improvement. Since P directly correlates to
the computational efficiency of the submanifold field model (see below), we keep P = 122.
Computational Efficiency. Increasing the point sample size P increases computation and memory.
Encoding time remains low since a lightweight PointNet-based encoder shares weights with all input
points, giving an inference speed of 1.72s per 1 million Gaussians for P = 122 with a batch size of
4096 on an RTX 5090. Decoding time is 4.20s per 1 million Gaussians, from embedding to Gaussian
parameters. The complexity is O(P) or O(n2) w.r.t. the grid size n. We utilize the advantage of
GPU parallel computation to boost the calculation for parameter fitting module. In the 4.20s of
decoding time, the fitting module (PCA + SH fitting) consumes only about 0.48s which is negligible
for large Gaussian scenes.
5
CONCLUSION AND LIMITATIONS
We introduced a geometry-aware submanifold field representation for 3D Gaussian Splatting that
maps each primitive to a color field on a canonical iso–probability ellipsoid and proved the mapping
is injective over core attributes. Built on this representation, our SF–VAE learns semantically mean-
ingful latents and yields higher-fidelity reconstructions and stronger zero-shot generalization than
capacity-matched raw-parameter baselines; our manifold distance (M-Dist) further aligns training
and evaluation with geometric/perceptual similarity.
10

<!-- page 11 -->
Published as a conference paper at ICLR 2026
Limitations and Outlook. Our current setup operates at the single-Gaussian level, while this en-
sures data invariance, it omits explicit inter-splat structure modeling for more complex represen-
tation learning. Promising directions include set/scene-level encoders with permutation-invariant
attention, point cloud to 3DGS inpainting, generative modeling with submanifold field embeddings,
temporal extensions to dynamic scenes, and applications to compression, retrieval, and regulariza-
tion in broader downstream 3DGS pipelines.
11

<!-- page 12 -->
Published as a conference paper at ICLR 2026
REFERENCES
Yanqi Bao, Tianyu Ding, Jing Huo, Yaoli Liu, Yuxin Li, Wenbin Li, Yang Gao, and Jiebo Luo. 3d
gaussian splatting: Survey, technologies, challenges, and opportunities. IEEE Transactions on
Circuits and Systems for Video Technology, 2025.
Jonathan T Barron, Ben Mildenhall, Dor Verbin, Pratul P Srinivasan, and Peter Hedman. Mip-nerf
360: Unbounded anti-aliased neural radiance fields. In CVPR, 2022.
Yoshua Bengio, Aaron Courville, and Pascal Vincent. Representation learning: A review and new
perspectives. IEEE transactions on pattern analysis and machine intelligence, 35(8):1798–1828,
2013.
Angel X Chang, Thomas Funkhouser, Leonidas Guibas, Pat Hanrahan, Qixing Huang, Zimo Li,
Silvio Savarese, Manolis Savva, Shuran Song, Hao Su, et al. Shapenet: An information-rich 3d
model repository. arXiv preprint arXiv:1512.03012, 2015.
David Charatan, Sizhe Lester Li, Andrea Tagliasacchi, and Vincent Sitzmann. pixelsplat: 3d gaus-
sian splats from image pairs for scalable generalizable 3d reconstruction. In CVPR, 2024.
Yiwen Chen, Zilong Chen, Chi Zhang, Feng Wang, Xiaofeng Yang, Yikai Wang, Zhongang Cai, Lei
Yang, Huaping Liu, and Guosheng Lin. Gaussianeditor: Swift and controllable 3d editing with
gaussian splatting. In CVPR, 2024a.
Yuedong Chen, Haofei Xu, Chuanxia Zheng, Bohan Zhuang, Marc Pollefeys, Andreas Geiger, Tat-
Jen Cham, and Jianfei Cai.
Mvsplat: Efficient 3d gaussian splatting from sparse multi-view
images. In ECCV, 2024b.
Zequn Chen, Jiezhi Yang, and Heng Yang. Pref3r: Pose-free feed-forward 3d gaussian splatting
from variable-length image sequence. arXiv preprint arXiv:2411.16877, 2024c.
Zilong Chen, Feng Wang, Yikai Wang, and Huaping Liu. Text-to-3d using gaussian splatting. In
CVPR, 2024d.
Sharath Girish, Kamal Gupta, and Abhinav Shrivastava. Eagles: Efficient accelerated 3d gaussians
with lightweight encodings. In ECCV, 2024.
Jun Guo, Xiaojian Ma, Yue Fan, Huaping Liu, and Qing Li. Semantic gaussians: Open-vocabulary
scene understanding with 3d gaussian splatting. arXiv preprint arXiv:2403.15624, 2024.
Sunghwan Hong, Jaewoo Jung, Heeseong Shin, Jisang Han, Jiaolong Yang, Chong Luo, and Seun-
gryong Kim. Pf3plat: Pose-free feed-forward 3d gaussian splatting. ICML, 2024.
Sergey Ioffe and Christian Szegedy. Batch normalization: Accelerating deep network training by
reducing internal covariate shift. In ICML, 2015.
Lihan Jiang, Yucheng Mao, Linning Xu, Tao Lu, Kerui Ren, Yichen Jin, Xudong Xu, Mulin Yu,
Jiangmiao Pang, Feng Zhao, et al. Anysplat: Feed-forward 3d gaussian splatting from uncon-
strained views. arXiv preprint arXiv:2505.23716, 2025.
Ying Jiang, Chang Yu, Tianyi Xie, Xuan Li, Yutao Feng, Huamin Wang, Minchen Li, Henry Lau,
Feng Gao, Yin Yang, et al. Vr-gs: A physical dynamics-aware interactive gaussian splatting
system in virtual reality. In SIGGRAPH, 2024.
Joongho Jo, Hyeongwon Kim, and Jongsun Park. Identifying unnecessary 3d gaussians using clus-
tering for fast rendering of 3d gaussian splatting. arXiv preprint arXiv:2402.13827, 2024.
Bernhard Kerbl, Georgios Kopanas, Thomas Leimk¨uhler, and George Drettakis. 3d gaussian splat-
ting for real-time radiance field rendering. ACM Trans. Graph., 2023.
Muhammed Kocabas, Jen-Hao Rick Chang, James Gabriel, Oncel Tuzel, and Anurag Ranjan. Hugs:
Human gaussian splats. In CVPR, 2024.
´Aron Samuel Kov´acs, Pedro Hermosilla, and Renata G Raidou. G-style: Stylized gaussian splatting.
In Computer Graphics Forum, 2024.
12

<!-- page 13 -->
Published as a conference paper at ICLR 2026
Dong In Lee, Hyeongcheol Park, Jiyoung Seo, Eunbyung Park, Hyunje Park, Ha Dam Baek,
Sangheon Shin, Sangmin Kim, and Sangpil Kim. Editsplat: Multi-view fusion and attention-
guided optimization for view-consistent 3d scene editing with 3d gaussian splatting. In CVPR,
2025.
Junseo Lee, Seokwon Lee, Jungi Lee, Junyong Park, and Jaewoong Sim. Gscore: Efficient radiance
field rendering via architectural support for 3d gaussian splatting. In Proceedings of the 29th ACM
International Conference on Architectural Support for Programming Languages and Operating
Systems, Volume 3, pp. 497–511, 2024.
Yue Li, Qi Ma, Runyi Yang, Huapeng Li, Mengjiao Ma, Bin Ren, Nikola Popovic, Nicu Sebe, Ender
Konukoglu, Theo Gevers, et al. Scenesplat: Gaussian splatting-based scene understanding with
vision-language pretraining. ICCV, 2025a.
Zhe Li, Zerong Zheng, Lizhen Wang, and Yebin Liu.
Animatable gaussians: Learning pose-
dependent gaussian maps for high-fidelity human avatar modeling. In CVPR, 2024.
Zhiqi Li, Chengrui Dong, Yiming Chen, Zhangchi Huang, and Peidong Liu. Vicasplat: A single run
is all you need for 3d gaussian splatting and camera estimation from unposed video frames. arXiv
preprint arXiv:2503.10286, 2025b.
Chenguo Lin, Panwang Pan, Bangbang Yang, Zeming Li, and Yadong Mu. Diffsplat: Repurposing
image diffusion models for scalable gaussian splat generation. arXiv preprint arXiv:2501.16764,
2025a.
Chin-Yang Lin, Cheng Sun, Fu-En Yang, Min-Hung Chen, Yen-Yu Lin, and Yu-Lun Liu. Longsplat:
Robust unposed 3d gaussian splatting for casual long videos. ICCV, 2025b.
Xin Lin, Shi Luo, Xiaojun Shan, Xiaoyu Zhou, Chao Ren, Lu Qi, Ming-Hsuan Yang, and Nuno
Vasconcelos. Hqgs: High-quality novel view synthesis with gaussian splatting in degraded scenes.
In The Thirteenth International Conference on Learning Representations, 2025c.
Qi Ma, Yue Li, Bin Ren, Nicu Sebe, Ender Konukoglu, Theo Gevers, Luc Van Gool, and Danda Pani
Paudel. A large-scale dataset of gaussian splats and their self-supervised pretraining. In 2025
International Conference on 3D Vision (3DV), 2025.
Francesco Palandra, Andrea Sanchietti, Daniele Baieri, and Emanuele Rodola. Gsedit: Efficient
text-guided editing of 3d objects via gaussian splatting. arXiv preprint arXiv:2403.05154, 2024.
Charles R Qi, Hao Su, Kaichun Mo, and Leonidas J Guibas. Pointnet: Deep learning on point sets
for 3d classification and segmentation. In Proceedings of the IEEE conference on computer vision
and pattern recognition, pp. 652–660, 2017.
Minghan Qin, Wanhua Li, Jiawei Zhou, Haoqian Wang, and Hanspeter Pfister. Langsplat: 3d lan-
guage gaussian splatting. In CVPR, 2024.
Seungjoo Shin, Jaesik Park, and Sunghyun Cho. Locality-aware gaussian compression for fast and
high-quality rendering. arXiv preprint arXiv:2501.05757, 2025.
Yipengjing Sun, Chenyang Wang, Shunyuan Zheng, Zonglin Li, Shengping Zhang, and Xiangyang
Ji.
Generalizable and relightable gaussian splatting for human novel view synthesis.
arXiv
preprint arXiv:2505.21502, 2025.
Jiaxiang Tang, Jiawei Ren, Hang Zhou, Ziwei Liu, and Gang Zeng. Dreamgaussian: Generative
gaussian splatting for efficient 3d content creation. arXiv preprint arXiv:2309.16653, 2023.
Qijian Tian, Xin Tan, Yuan Xie, and Lizhuang Ma. Drivingforward: Feed-forward 3d gaussian
splatting for driving scene reconstruction from flexible surround-view input. In AAAI, 2025.
Cyrus Vachha and Ayaan Haque. Instruct-gs2gs: Editing 3d gaussian splats with instructions, 2024.
URL https://instruct-gs2gs.github.io/.
Tongzhou Wang and Phillip Isola. Understanding contrastive representation learning through align-
ment and uniformity on the hypersphere. In International conference on machine learning, pp.
9929–9939. PMLR, 2020.
13

<!-- page 14 -->
Published as a conference paper at ICLR 2026
Xiaoyuan Wang, Yizhou Zhao, Botao Ye, Xiaojun Shan, Weijie Lyu, Lu Qi, Kelvin CK Chan, Yinx-
iao Li, and Ming-Hsuan Yang. Holigs: Holistic gaussian splatting for embodied view synthesis.
NeurIPS, 2025.
Yue Wang, Yongbin Sun, Ziwei Liu, Sanjay E. Sarma, Michael M. Bronstein, and Justin M.
Solomon. Dynamic graph cnn for learning on point clouds. ACM Transactions on Graphics
(TOG), 2019.
Christopher Wewer, Kevin Raj, Eddy Ilg, Bernt Schiele, and Jan Eric Lenssen. latentsplat: Autoen-
coding variational gaussians for fast generalizable 3d reconstruction. In ECCV, 2024.
Minye Wu and Tinne Tuytelaars.
Implicit gaussian splatting with efficient multi-level tri-plane
representation. CoRR, 2024.
Haozhe Xie, Zhaoxi Chen, Fangzhou Hong, and Ziwei Liu. Generative gaussian splatting for un-
bounded 3d city generation. In Proceedings of the Computer Vision and Pattern Recognition
Conference, pp. 6111–6120, 2025.
Tianyi Xie, Zeshun Zong, Yuxing Qiu, Xuan Li, Yutao Feng, Yin Yang, and Chenfanfu Jiang. Phys-
gaussian: Physics-integrated 3d gaussians for generative dynamics. In CVPR, 2024.
Yunzhi Yan, Haotong Lin, Chenxu Zhou, Weijie Wang, Haiyang Sun, Kun Zhan, Xianpeng Lang,
Xiaowei Zhou, and Sida Peng. Street gaussians for modeling dynamic urban scenes.(2023). arXiv
preprint arXiv:2401.01339, 2023.
Qi Yang, Le Yang, Geert Van Der Auwera, and Zhu Li. Hybridgs: High-efficiency gaussian splat-
ting data compression using dual-channel sparse representation and point cloud encoder. arXiv
preprint arXiv:2505.01938, 2025.
Taoran Yi, Jiemin Fang, Junjie Wang, Guanjun Wu, Lingxi Xie, Xiaopeng Zhang, Wenyu Liu,
Qi Tian, and Xinggang Wang. Gaussiandreamer: Fast generation from text to 3d gaussians by
bridging 2d and 3d diffusion models. In CVPR, 2024.
Xin-Yi Yu, Jun-Xin Yu, Li-Bo Zhou, Yan Wei, and Lin-Lin Ou. Instantstylegaussian: Efficient art
style transfer with 3d gaussian splatting. arXiv preprint arXiv:2408.04249, 2024.
Dingxi Zhang, Yu-Jie Yuan, Zhuoxun Chen, Fang-Lue Zhang, Zhenliang He, Shiguang Shan,
and Lin Gao.
Stylizedgs: Controllable stylization for 3d gaussian splatting.
arXiv preprint
arXiv:2404.05220, 2024.
Shunyuan Zheng, Boyao Zhou, Ruizhi Shao, Boning Liu, Shengping Zhang, Liqiang Nie, and Yebin
Liu. Gps-gaussian: Generalizable pixel-wise 3d gaussian splatting for real-time human novel view
synthesis. In CVPR, 2024.
Mikel Zhobro, Andreas Ren´e Geist, and Georg Martius. Learning 3d-gaussian simulators from rgb
videos. arXiv preprint arXiv:2503.24009, 2025.
Licheng Zhong, Hong-Xing Yu, Jiajun Wu, and Yunzhu Li. Reconstruction and simulation of elastic
objects with spring-mass 3d gaussians. In ECCV, 2024.
Hongyu Zhou, Jiahao Shao, Lu Xu, Dongfeng Bai, Weichao Qiu, Bingbing Liu, Yue Wang, Andreas
Geiger, and Yiyi Liao. Hugs: Holistic urban 3d scene understanding via gaussian splatting. In
CVPR, 2024a.
Junsheng Zhou, Weiqi Zhang, and Yu-Shen Liu. Diffgs: Functional gaussian splatting diffusion.
NeurIPS, 2024b.
Xiaoyu Zhou, Zhiwei Lin, Xiaojun Shan, Yongtao Wang, Deqing Sun, and Ming-Hsuan Yang. Driv-
inggaussian: Composite gaussian splatting for surrounding dynamic autonomous driving scenes.
In CVPR, 2024c.
14

<!-- page 15 -->
Published as a conference paper at ICLR 2026
A
PROOF OF PROPOSITION 1
We construct two distinct parameter sets, θ1 = {q1, s1, c1, o1} and θ2 = {q2, s2, c2, o2} with θ1 ̸=
θ2, that generate the identical Single Gaussian Radiance Field (SGRF). The identity LG1(x, d) =
LG2(x, d) for all (x, d) requires two conditions to be met:
1. Geometric Equivalence: The covariance matrices must be equal, Σ1 = Σ2, which implies
that the volume densities σG(x) are identical. We also assume equal opacity, o1 = o2.
2. Appearance Equivalence: The view-dependent color functions must be identical, which
requires SH(c1, R⊤
1 d) = SH(c2, R⊤
2 d) for all d ∈S2, where R is the rotation matrix for
the quaternion q.
We construct a distinct parameter set θ2 by considering a discrete symmetry of the Gaussian ellip-
soid. Let θ1 = {q1, s1, c1, o1} be an initial parameterization.
Let Rflip be a rotation matrix corresponding to a 180-degree rotation about one of the local axes
(e.g., the z-axis), such that Rflip = diag(−1, −1, 1). Rflip is its own inverse, R⊤
flip = Rflip. We define
a new parameter set θ2 as follows:
• Let the new rotation be R2 = R1Rflip. This defines a new quaternion q2 ̸= q1.
• Let the scales and opacity remain unchanged: s2 = s1 and o2 = o1.
First, we verify geometric equivalence. The new covariance matrix Σ2 is:
Σ2 = R2diag(s2)2R⊤
2 = (R1Rflip)diag(s1)2(R1Rflip)⊤
= R1
 Rflipdiag(s1)2R⊤
flip

R⊤
1
Since Rflip is diagonal, it commutes with the diagonal scaling matrix diag(s1)2, meaning the term
in parentheses equals diag(s1)2. Therefore,
Σ2 = R1diag(s1)2R⊤
1 = Σ1.
Geometric equivalence is satisfied.
Next, for appearance equivalence, we must find SH coefficients c2 such that:
SH(c1, R⊤
1 d) = SH(c2, (R1Rflip)⊤d) = SH(c2, R⊤
flipR⊤
1 d).
Let v = R⊤
1 d be the view direction in the local frame of the first Gaussian. The condition becomes
SH(c1, v) = SH(c2, R⊤
flipv). This states that the function defined by c2 when evaluated on a trans-
formed vector must equal the function defined by c1 on the original vector. This is equivalent to
stating that the function itself has been rotated. The properties of spherical harmonics guarantee that
for any rotation, there exists a linear transformation (the Wigner D-matrix D) that maps the original
coefficients to the new ones. We can therefore find c2 such that:
c2 = D(Rflip)c1.
We have constructed a parameter set θ2 = {q2, s1, c2, o1}, which is distinct from θ1 (since q2 ̸=
q1) yet defines the identical radiance field. This discrete symmetry exists for any Gaussian, proving
the general proposition.
Furthermore, this non-uniqueness expands from a discrete set to a continuous manifold of solutions
for symmetric geometries.
• Case A (Isotropic): If s = (s, s, s)⊤, the covariance matrix Σ = s2I is invariant under any
rotation. This gives rise to a continuous, multi-parameter family of equivalent solutions.
• Case B (Spheroidal): If two scale components are equal (e.g., s = (sa, sa, sb)⊤), Σ is
invariant to any rotation around the local axis of symmetry, resulting in a one-parameter
continuous family of redundant solutions.
In all such cases, a corresponding transformation on the SH coefficients preserves appearance equiv-
alence. Since non-unique parameterizations exist in all cases, the proposition is proven.
15

<!-- page 16 -->
Published as a conference paper at ICLR 2026
B
PROOF OF UNIQUENESS OF THE REPRESENTATION Ei = (Mi, Fi)
Assume ϕG1 = ϕG2, namely, ρG1(x) = ρG2(x), ∀x ∈R3 and cG1(d) = cG2(d), ∀d ∈S2. We show
this leads to E1 = E2 for two SGRFs. This implies both M1 = M2 and F1 = F2.
The volume densities are equal:
exp

−1
2(x −µ1)⊤Σ−1
1 (x −µ1)

= exp

−1
2(x −µ2)⊤Σ−1
2 (x −µ2)

Taking the natural logarithm of both sides yields that the quadratic forms are identical for all x:
(x −µ1)⊤Σ−1
1 (x −µ1) = (x −µ2)⊤Σ−1
2 (x −µ2)
An unnormalized Gaussian distribution is uniquely defined by its mean and covariance. Therefore,
this equality implies µ1 = µ2 and Σ1 = Σ2.
The submanifold Mi is defined as the level set:
Mi = {x ∈R3 | (x −µi)⊤Σ−1
i (x −µi) = r2}
Since the parameters (µi, Σi) that define the level set are identical for both primitives, the resulting
sets of points must also be identical. Thus, M1 = M2.
The submanifold color field Fi is defined for a point x ∈Mi as:
Fi(x) = cGi(dx),
where
dx = (x −µi)/∥x −µi∥
From the hypothesis, we know that cG1(d) = cG2(d) holds for any unit direction vector d ∈S2.
For any point x on the common manifold M = M1 = M2, its corresponding direction vector dx
is an element of S2. We can therefore apply the hypothesis for this specific direction:
cG1(dx) = cG2(dx)
By the definition of Fi, this directly implies:
F1(x) = F2(x)
This holds for all x ∈M. Thus, the color fields F1 and F2 are identical.
C
IMPLEMENTATION DETAILS
C.1
SUBMANIFOLD FIELD VAE
For completeness, we note a few aspects not detailed in the main text. Also see Alg. 1 for steps in
one training step.
Uniform Point Sampling. The submanifold field Ei is discretized by using a uniform mesh grid
of size (n, n) to sample P = n2 points on the ellipsoidal surface Mi with respect to area, forming
Pi = {(xi,k, Fi(xi,k), αi)}P
k=1.
Decoding Gaussian Parameters. After decoding, we recover Gaussian parameters from the recon-
structed point cloud by first applying batched PCA to estimate the ellipsoid axes and orientation:
we compute the mean and covariance of the points, perform eigen decomposition to obtain prin-
cipal axes, and ensure a right-handed coordinate system. The logarithm of the axis lengths gives
the scale parameters, and the rotation matrix is converted to a quaternion using a numerically stable
batched algorithm. For appearance, we compute ellipsoid-normalized directions for each point and
fit spherical harmonics coefficients to the RGB values via regularized batched least-squares. Opacity
is estimated by averaging and logit-transforming the per-point values.
16

<!-- page 17 -->
Published as a conference paper at ICLR 2026
Algorithm 1 SF-VAE: one training step for a minibatch of submanifold fields
Require: Batch {(µi, Σi, ci, oi)}B
i=1, fixed r2=1, point count P
1: for each i do
2:
(Sampling on Mi) Sample {uk}P
k=1 quasi-uniformly on S2; set xi,k ←µi + Σ1/2
i
uk so
that (xi,k −µi)⊤Σ−1
i (xi,k −µi) = r2
3:
(Color/opacity) di,k ←(xi,k −µi)/∥xi,k −µi∥;
ci,k ←SH(ci, di,k);
αi,k ←σ(oi)
4:
(Point set) Pi ←{(xi,k, ci,k, αi,k)}P
k=1
5: end for
6: (Encode) (µz
i , log σ2,z
i
) ←E(Pi); zi ←µz
i + σz
i ⊙ε, ε ∼N(0, I)
7: (Decode) ( c
Mi, bFi, ˆαi) ←D(zi); bPi ←{(ˆxi,k, bFi(ˆxi,k), ˆαi)}
8: (Recover parameters) bΣi ←PCA({ˆxi,k}); bci ←arg minc
P
k ∥SH(c, ˆdi,k) −bFi(ˆxi,k)∥2
2
9: (Loss) Lrec ←W (ε)
2 (Pi, bPi) with d(·, ·) from Eq. (8); L ←Lrec + β · KL
10: (Update) θE, θD ←θE, θD −η∇θE,θDL
C.2
GENERATED 3D GAUSSIAN PRIMITIVES DATASET
Parameter priors and sampling Each primitive Gi is sampled as θi = {µi, qi, si, ci, oi} and
converted to (µi, Σi, ci, αi) with Σi = R(qi) diag(exp(si))2 R(qi)⊤and αi = σ(oi). Unless
otherwise stated we use:
• Mean. µi = (0, 0, 0). Since our setting only samples single Gaussians, extrinsic informa-
tion is not needed.
• Rotation. qi is sampled uniformly on SO(3) (normalized and, if needed, enforce a canon-
ical sign).
• Scale. Log–axes si ∈R3 drawn i.i.d. from U([smin, smax]); set activated scales exp(si).
• SH coefficients. Let β > 1 be the decay factor (in code, β = 4). For degree ℓ= 0, . . . , L,
we draw the (2ℓ+1)-dimensional SH band as cℓ∼N
 0, σ2
ℓI2ℓ+1

,
σℓ= β−ℓ, i.e.,
Var[ cℓ,m ] = β−2ℓ
for m = −ℓ, . . . , ℓ. If coefficients above the chosen degree L are
padded up to Lmax, we use i.i.d. noise cℓ,m ∼N(0, σ2
void) with σvoid = 0.05.
• Opacity. Logit oi ∼U([omin, omax]), with αi = σ(oi).
To sum up, we can describe the data distribution in this dataset as:
D =

(µi, qi, si, ci, oi)
	N
i=1
i.i.d.
∼
δ0
|{z}
µ
× U
 SO(3)

|
{z
}
q
× U
 [smin, smax]
3
|
{z
}
s
×


Y
c∈{R,G,B}
h
L
Y
ℓ=0
N
 0, β−2ℓ2ℓ+1 ×
Lmax
Y
ℓ=L+1
N
 0, σ2
void
2ℓ+1i


|
{z
}
c∈R3×K, K=(Lmax+1)2
× U
 [omin, omax]

|
{z
}
o
,
β > 1 (default 4), σvoid = 0.05.
where β > 1 is the SH variance–decay factor (default β=4) and σvoid is the padding noise std (default
0.05). Activations used downstream are Σi = R(qi) diag
 exp(si)
2R(qi)⊤and αi = σ(oi).
Defaults and ablations Default hyperparameters: N=500K, Lmax=3 (K=16), P=144, smin= −
8, smax=0, omin= −5, omax=10. These parameters are built from statistical analysis of data
distribution in diverse 3DGS datasets. We ablate P ∈{36, 64, 144, 576} in the main paper to assess
reconstruction vs. cost.
Data Formatting and Processing. For each of the randomly synthesized primitive we store the
native tuple θi (float32 arrays for µ, q, s, c, o). The discretized field Pi is sampled from the
primitive of θi to a tensor of (B, P, 7) where 7 is (x, y, z, r, g, b, α). It can be obtained at runtime to
reduce memory and storage requirements. The dataset exposes toggles to return either θ or P.
17

<!-- page 18 -->
Published as a conference paper at ICLR 2026
Algorithm 2 GAUSSIANGEN: Generate one colored point cloud from a random Gaussian
Require: point count P (default 144), SH degree Lmax with K = (Lmax+1)2
1: Sample raw parameters µ ∈R3, s ∈R3, q ∈SO(3), o ∈R, feat dc ∈R3, feat extra ∈
R3(K−1)
2: Assemble SH coefficients C ∈R3×K by stacking per channel:
Cr ←[feat dc[0], feat extra[0 : (K −1)]]
Cg ←[feat dc[1], feat extra[(K −1) : 2(K −1)]]
Cb ←[feat dc[2], feat extra[2(K −1) : 3(K −1)]]
3: Activate parameters
q ←q/∥q∥; R ←R(q); σ ←exp(s); α ←σ(o)
4: Build surface grid
n ←
√
P; create angular grids u∈[0, 2π) and v∈[0, π] of size n × n
directions d(u, v) ∈S2 from spherical angles (u, v)
5: Map to ellipsoid (iso-density r2=1)
x(u, v) ←µ + R diag(σ) d(u, v)
6: Evaluate color field
c(u, v) ←SH(C, d(u, v))
(optional) color post-process: c ←clip(c+0.5, 0, 1)
7: Pack output
replicate α to all points; flatten grids to P points
return {(xk, ck, α)}P
k=1 ∈RP ×7
// (x, y, z, r, g, b, α)
D
ADDITIONAL EVALUATION AND VISUALIZATION RESULTS
D.1
INTERPOLATION & NOISE VISUALIZATIONS
Parametric
SF Embedding
Source
Interpolate
Target
Figure 8: Sample visual comparison of linear interpolation in submanifold field embedding space
and parametric space. Interpolation in SF embedding shows smooth transition from source to target.
Perturb s and q will dramatically change the geometry of the resulted Gaussian, verifying the feature
heterogeneous problem.
Figure 9: When rotation q is inverted to −q, the submanifold field model (left) can still correctly
reconstruct the scene, while parametric model fails to process this equivalent rotation.
18

<!-- page 19 -->
Published as a conference paper at ICLR 2026
D.2
ADDITIONAL RECONSTRUCTION VISUALIZATIONS
Ground Truth
MLP / MLP
MLP / SF-VAE
SF-VAE
Figure 10: Full qualitative results for rasterization using different model configurations on Mip-
NeRF 360.
19

<!-- page 20 -->
Published as a conference paper at ICLR 2026
D.3
UNSUPERVISED CLUSTERING QUANTITATIVE RESULTS
Clustered Feature
Silhouette ↑
Cluster Compactness (MSE ↓)
Parameters
0.090
71.306
MLP / MLP
0.084
50.761
MLP / SF-VAE
0.086
50.916
SF-VAE
0.113
48.282
Table 4: Quantitative comparisons on unsupervised clustering based on the respective clustered
feature. Higher silhouette is better; lower compactness (MSE) is better.
D.4
GAUSSIAN NEURAL FIELD DETAILS & VISUALIZATIONS
Network Structure for Gaussian Neural Fields. We define a compact per-scene MLP that takes
only 3D coordinates ((x,y,z)), applies sinusoidal/Fourier positional encoding, and passes the en-
coded vector through a fully connected backbone (256-width 4 layers for ShapeSplat, 512-width 8
layers for Mip-NeRF 360) with a single mid-network skip that re-concatenates the encoded input
for better conditioning. The same network architecture is used for both targets; the only difference
is the final output dimension: either 32 for the SF embedding or 56 for the no-position Gaussian
parameters ([q(4), s(3), SH(3K), o(1)]). Hidden layers use standard ReLU/SiLU activations, the
output is linear, and the overall footprint remains lightweight (≈2×105 parameters for ShapeSplat,
≈1.8×106 for Mip-NeRF 360) for querying at Gaussian centers to yield SF embeddings or directly
renderable Gaussian parameters.
Ground Truth
SF Embedding
Parameter
Figure 11: Arbitrarily picked visual comparisons of Gaussian Neural Fields trained with target
Gaussian parameters and submanifold field embeddings. The submanifold field embedding results
is qualitatively better under matching settings, indicating that the SF embedding is a better learning
target for regression tasks such as training a neural field.
20
