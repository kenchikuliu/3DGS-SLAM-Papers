<!-- page 1 -->
FastAvatar:
Instant 3D Gaussian Splatting for Faces from Single Unconstrained Poses
Hao Liang
Rice University
Houston, TX, USA
hl106@rice.edu
Zhixuan Ge
Rice University
Houston, TX, USA
zg33@rice.edu
Ashish Tiwari
Rice University
Houston, TX, USA
ashish.tiwari@iitgn.ac.in
Soumendu Majee
Samsung Research America
Dallas, TX, USA
s.majee@samsung.com
Dilshan Godaliyadda
Samsung Research America
Dallas, TX, USA
dilshan.g@samsung.com
Ashok Veeraraghavan
Rice University
Houston, TX, USA
vashok@rice.edu
Guha Balakrishnan
Rice University
Houston, TX, USA
guha@rice.edu
Encoder
Decoder
FastAvatar
3 seconds
3D Gaussian Splatting
Representations
(3DGS)
Novel View Synthesis
Real-time Animation
Figure 1. FastAvatar produces high-quality 3D face avatars and animations from a single input image. Given an arbitrary-pose
face image, FastAvatar reconstructs a complete 3D Gaussian Splatting (3DGS) representation and refines it using a geometry–appearance
optimization routine requiring only ∼3 seconds on a single NVIDIA A100 GPU. Once reconstructed, the avatar supports photorealistic
novel-view synthesis and smooth expression animation driven by FLAME-guided pose and expression controls, while preserving identity
and rendering quality across all viewpoints.
Abstract
We present FastAvatar, a fast and robust algorithm for
single-image 3D face reconstruction using 3D Gaussian
Splatting (3DGS). Given a single input image from an
arbitrary pose, FastAvatar recovers a high-quality, full-
head 3DGS avatar in approximately 3 seconds on a sin-
gle NVIDIA A100 GPU. We use a two-stage design: a
feed-forward encoder–decoder predicts coarse face geom-
etry by regressing Gaussian structure from a pose-invariant
identity embedding, and a lightweight test-time refinement
stage then optimizes the appearance parameters for pho-
torealistic rendering.
This hybrid strategy combines the
speed and stability of direct prediction with the accuracy
of optimization, enabling strong identity preservation even
under extreme input poses. FastAvatar achieves state-of-
1
arXiv:2508.18389v2  [cs.CV]  25 Nov 2025

<!-- page 2 -->
the-art reconstruction quality (24.01 dB PSNR, 0.91 SSIM)
while running over 600× faster than existing per-subject
optimization methods (e.g., FlashAvatar, GaussianAvatars,
GASP). Once reconstructed, our avatars support photore-
alistic novel-view synthesis and FLAME-guided expression
animation, enabling controllable reenactment from a single
image. By jointly offering high fidelity, robustness to pose,
and rapid reconstruction, FastAvatar significantly broadens
the applicability of 3DGS-based facial avatars.
1. Introduction
Creating 3D face models from images is a long-standing
problem in computer vision and graphics, and is of signif-
icant current interest in digital avatar applications such as
virtual reality, gaming, and content creation. 3D face model
frameworks that enable fast and high-resolution novel view
rendering performance from one or few input views are
needed to support these applications. Classical parametric
face models based on simple statistical approaches [2, 3, 34]
offer real-time fitting and rendering speed, but are limited in
their expressive power. In contrast, recent approaches based
on the Neural Radiance Field (NeRF) [43] and 3D Gaussian
Splatting (3DGS) [27] neural rendering frameworks offer
state-of-the-art expressive power, with 3DGS even enabling
real-time rendering speed. However, these algorithms have
critical limitations: they require expensive per-subject opti-
mizations from multi-view captures with fitting times rang-
ing from minutes to hours, restricting their practical deploy-
ment in many consumer applications.
In
this
study,
we
aim
to
move
beyond
purely
optimization-based avatar construction and propose a fast,
robust framework that reconstructs a high-quality 3DGS
face model from a single input image. Purely feed-forward
face generation approaches, typically based on GANs [20]
or diffusion models [22], are often constrained to (near-
)frontal viewpoints due to data bias and struggle to gen-
eralize under large pose variation, frequently exhibiting
artifacts or identity drift when viewed from novel an-
gles [5, 18]. At the same time, fully optimization-driven
3DGS reconstruction methods deliver high fidelity but re-
quire minutes of per-subject fitting and are unsuitable for
interactive user applications. This motivates the need for
a single-view reconstruction framework that combines the
speed and stability of direct prediction with the fidelity of
optimization, while remaining robust to large input pose
variation and maintaining faithful identity preservation.
To address these challenges, we present FastAvatar, a
fast framework for 3DGS face reconstruction from a sin-
gle image with arbitrary pose. FastAvatar is driven by two
key insights. First, inspired by classical morphable face
models [2], we construct a 3DGS “template” face repre-
sentation by averaging the Gaussian parameters across a
set of subject-specific 3DGS models. Unlike prior work
that initializes Gaussians randomly or requires per-subject
optimization [38, 49, 52, 71], this template provides a ge-
ometric prior that enables fast and stable reconstructions.
At test time, FastAvatar represents a new identity by pre-
dicting residuals to this template using an encoder–decoder
network.
Second, to achieve identity preservation even under ex-
treme viewpoints, we constrain the encoder to map all views
of the same individual to a shared latent vector using pre-
trained face recognition features [10] and contrastive learn-
ing.
The decoder then maps this identity embedding to
Gaussian parameter residuals that refine the template into
a subject-specific 3D representation. This encoder–decoder
architecture effectively learns a strong geometry prior over
human faces: all identities are reconstructed as deforma-
tions of a shared canonical 3DGS template. As a result,
FastAvatar produces stable, 3D-consistent geometry even
from extreme input poses, avoiding the view-dependent ar-
tifacts or identity drift commonly observed in unconstrained
image-to-3D prediction networks. This feed-forward pre-
diction produces the coarse geometry, which we subse-
quently refine through a lightweight optimization stage to
recover high-quality appearance while preserving identity.
We evaluated FastAvatar with several quantitative
and qualitative experiments using the Nersemble test
dataset [29] and compared against recent 3DGS-based and
diffusion-based avatar methods.
Given three distinct in-
put poses (frontal and two extreme views), we measured
reconstruction quality across 15 novel viewpoints and ob-
serve that FastAvatar achieves 24 dB PSNR in approxi-
mately 3 seconds, outperforming feed-forward baselines
such as GAGAvatar [7] (16 dB), LAM [21](14 dB), and
running 600× faster than purely optimization-driven ap-
proaches such as GaussianAvatars [49], FlashAvatar [67],
DiffusionRig [13], and Arc2Avatar [18]. FastAvatar main-
tains stable identity and reconstruction quality across large
input poses, from frontal to extreme profiles, whereas ex-
isting feed-forward or template-free approaches tend to de-
grade or drift. We also provide qualitative examples us-
ing FastAvatar to perform FLAME-guided expression an-
imation from a single image. By combining high fidelity,
robustness to pose, and rapid reconstruction, FastAvatar
broadens the applicability of 3D Gaussian Splatting to prac-
tical and interactive avatar creation.
2. Related Work
Recovering a high-quality 3D face from images is a long-
standing problem in computer vision and graphics.
The
seminal 3D Morphable Model (3DMM) [2, 3, 33, 56] repre-
sents facial geometry and appearance using statistical mesh-
based bases learned from many subjects. FLAME [34] ex-
tends these models to capture expression variations and ar-
2

<!-- page 3 -->
ticulated jaw and neck motion using thousands of 3D head
scans [9, 15]. Both 3DMM- and FLAME-based methods
estimate parameters via inverse rendering or neural regres-
sion, but their low-rank bases limit expressiveness for high-
frequency facial details such as subtle skin variation and
hair patterns.
In the past five years, the field of neural rendering has
opened new capabilities in 3D face reconstruction. Neu-
ral Radiance Fields (NeRF) [43] and their dynamic vari-
ants [14, 37, 46, 47, 47] enable photorealistic view synthe-
sis by representing scenes as continuous volumetric fields.
NeRFs have also been developed for face reconstruction
[4, 16, 23, 45, 60, 61, 79].
However, NeRFs are typ-
ically slow to train and render, often requiring hours to
fit a new scene.
3D Gaussian Splatting (3DGS) is a
compelling alternative to NeRF that explicitly represents
scenes as a set of anisotropic Gaussian primitives with
learned parameters [27]. 3DGS supports high-quality ren-
dering at real-time frame rates and has been adapted to
face and head modeling, achieving impressive visual qual-
ity [12, 41, 65, 70]. Recent studies have started to combine
parametric meshes with 3DGS to gain the advantages of
dense correspondence and identity-expression disentangle-
ment from meshes, along with efficient, high-quality ren-
dering from 3DGS [19, 24, 30, 49–53, 62, 67, 69, 71].
These methods typically attach Gaussians to vertices (or
surface patches) of a fitted parametric head mesh and op-
timize per-Gaussian parameters (means, scales, appear-
ances) to the observed image(s). In addition, while most
of these methods require multi-view capture, several have
been extended to the far more under-constrained single-
view setting [21, 28, 32, 36, 42, 59, 72, 80]. Unlike prior
mesh-anchored 3DGS methods that initialize templates ran-
domly or jointly optimize them with the decoder (entan-
gling with the latent space), we fix the template by aver-
aging subject-specific optimized 3DGS models and only
learn offsets—yielding smaller, better-conditioned residu-
als, removing the (K × P) parameter block, and improving
stability and generalization. While these hybrid 3DGS ap-
proaches can produce detailed reconstructions and can fit
scenes far faster than NeRFs (often nearly 10× faster), their
fitting times are still far from real-time due to their reliance
on per-face iterative optimization.
In contrast to iterative optimization approaches, feed-
forward methods directly map input images to outputs —
either 3D models or novel views — resulting in real-time
fitting speed. Several feed-forward methods directly predict
parameters to NeRF or 3DGS models given one or more
input images [7, 8, 35, 36, 39, 63, 73, 75, 78]. These ap-
proaches work well on frontal or near-frontal inputs with
limited pose variation, but often exhibit pose-dependent in-
consistencies; reconstructions from non-frontal inputs can
differ noticeably in identity and geometry compared to
frontal inputs. Another family of feed-forward methods use
generative models such as diffusion models [6, 18, 40, 44,
54, 55, 58, 66, 68] or GANs [1, 5, 11, 17, 25, 26, 31, 57, 77]
to directly infer novel views by exploiting data-driven pri-
ors. Generative models now offer photorealistic synthesis
quality, but do not typically construct explicit 3D geometry,
and thus often produce distortions, drifting facial structures,
and identity hallucinations with pose changes.
FastAvatar, the proposed algorithm in this study, inte-
grates several ideas developed in these existing lines of
work to perform high-quality, real-time novel view synthe-
sis given only a single input face image. FastAvatar uses a
feed-forward architecture to predict deformations to a tem-
plate 3DGS model, taking inspiration from morphable mod-
els. The architecture also maps the input image into a pose-
invariant embedding, enabling better identity-pose disen-
tanglement given an input image from any arbitrary pose.
3. Method
Given a single face image I, our goal is to reconstruct a
complete 3DGS model that enables high-quality novel-view
synthesis and animation. The main challenge is to infer
thousands of Gaussian parameters from a single 2D obser-
vation under extreme pose variation. FastAvatar addresses
this using a canonical 3DGS template and pose-invariant
residual prediction. We first build a template by averaging
Gaussian parameters across subject-specific 3DGS models,
with all Gaussians placed at consistent FLAME-tracked lo-
cations. This provides a strong geometric prior and ensures
consistent correspondence across subjects.
At test time, an encoder maps the input image to a
pose-independent identity embedding, and a decoder pre-
dicts per-Gaussian residual parameters that deform the tem-
plate into a subject-specific model.
For non-position at-
tributes (opacity, scale, rotation, SH appearance), the de-
coder predicts residuals from the template values. For posi-
tions, it predicts offsets from the canonical FLAME-tracked
locations to maintain stable geometry under large view-
point changes. This feed-forward prediction yields a coarse
3DGS geometry, which is further refined by a lightweight
appearance optimization stage for accurate rendering.
3.1. Preliminaries: 3D Gaussian Splatting (3DGS)
A 3D Gaussian Splatting (3DGS) model [27] represents a
scene using K anisotropic Gaussians M = {Gk}K
k=1, each
defined by geometric and appearance parameters: center
µk ∈R3, opacity αk ∈[0, 1], spherical harmonic (SH) color
coefficients ck, and a covariance matrix Σk = RkS2
kRT
k
factored into a rotation Rk (quaternion qk) and diagonal
scale Sk. Rendering uses differentiable rasterization, where
3

<!-- page 4 -->
Decoder 
(hθ)
∆mean
∆scale
∆rotation
∆color
∆opacity
Apply
offsets
Training 
Only
Splatting
Decoder Loss
Encoder 
(gϕ)
...
...
...
...
Multi-view images
per subject
FLAME
meshes
Initial
Gaussians
3DGS
models
Template 3DGS
face model (T )
Gaussian
Embedding
(e) 
(a) Template Face Construction
(b) Encoder-Decoder Pipeline
∆G
Splatting
Identity
Embedding
(ŵ)
Identity
Embedding (w)
Training & 
Testing
Testing 
Only
Encoder Loss
Input Image
3DGS Model
Average
Novel Views
Figure 2. FastAvatar framework. (a) Template 3DGS face model construction. FastAvatar constructs a template 3DGS face model T
by averaging parameters of Gaussians across 3DGS models fit on a training set of subjects. (b) Encoder-Decoder Pipeline. FastAvatar uses
an encoder-decoder architecture to map an input image to parameter offsets of the template 3DGS model constructed in (a). We train the
decoder to predict parameter offsets for each Gaussian conditioned on subject-specific and Gaussian-specific embedding vectors. We train
the encoder to map multi-pose images of the same identity to the same subject-specific embedding. At inference time, FastAvatar passes
an image into the encoder to generate a subject-specific embedding, and decodes this embedding to obtain Gaussian-specific parameter
offsets, that, combined with template T, yields a full 3DGS avatar in real time (≤3 seconds) with refinement.
Gaussians are alpha-blended along each ray:
C =
D
X
d=1
cd αd
Y
j<d
(1 −αj),
with cd evaluated from SH coefficients and αd incorporat-
ing opacity and projected density.
3.2. Template 3DGS Face Model Construction
Directly inferring the parameters of a full 3DGS model from
a single image is highly under-constrained due to the large
number of parameters involved: each Gaussian has 59 pa-
rameters including geometry (center, scale, rotation), opac-
ity, and 48 SH appearance coefficients. Inspired by clas-
sical morphable models [3], we reduce this complexity by
predicting only the residual deformations required to adapt
a data-driven template 3DGS model T to the input image.
Following GaussianAvatars [49], we place one Gaus-
sian at the center of each triangular face of the FLAME
mesh [34] and add additional Gaussians for the upper and
lower teeth.
This produces a canonical set of K mesh-
attached Gaussians that share consistent semantic meaning
across subjects and provide a stable geometric reference for
learning. This design also enables efficient real-time anima-
tion, as described in Section 3.5.
As shown in Fig.2(a), to construct the template T , we
first optimize individual 3DGS models {Mi}N
i=1 for all
training subjects, each initialized with Gaussians placed at
these consistent FLAME-aligned locations. We then ap-
ply standard 3DGS optimization [74] to recover subject-
specific geometry and appearance.
Finally, the template
T is obtained by averaging the parameters of correspond-
ing Gaussians across subjects. Compared to random ini-
tialization or joint template optimization [38, 49, 52, 71],
this simple averaging procedure yields a compact, stable
prior requiring only small subject-specific residuals during
reconstruction. We show the effectiveness of the average
template in Sec. 4.6, and a more detailed analysis in Sup-
plementary.
3.3. Encoder-Decoder Network
The encoder–decoder network maps an input image I to
residual Gaussian parameters that deform the template T
into a subject-specific 3DGS model.
Because I can ap-
pear under arbitrary viewpoints, the encoder is designed
to produce a pose-invariant latent code that captures only
identity-specific information.
Training the encoder and decoder end-to-end leads to a
degenerate solution where the network collapses to predict-
ing an average face. To avoid this, we adopt a two-stage
training strategy. We first train the decoder while treating
the latent codes for all training subjects as learnable vari-
ables. This stage forces the decoder to learn a smooth and
generalizable latent space for predicting Gaussian residuals,
rather than memorizing per-identity solutions.
After the decoder is trained, we freeze it and train the en-
coder to map images into the learned latent space. The en-
coder is guided by features from a large-scale face recogni-
tion model to ensure pose invariance and strong identity dis-
crimination. This staged design yields an encoder that gen-
eralizes reliably to unseen identities and expressions, while
the decoder provides stable geometry prediction anchored
to the canonical template.
4

<!-- page 5 -->
3.3.1. Decoder Design and Optimization
The decoder hθ maps a pose-invariant identity code w ∈
R|w| and a Gaussian embedding ek ∈R|e| to residual param-
eters ∆Gk = {∆µk, ∆sk, ∆qk, ∆αk, ∆ck} for Gaussian
k. The identity code w captures subject-dependent proper-
ties, while ek provides localized context for each Gaussian.
For appearance parameters (scale, rotation, opacity, SH
coefficients), residuals are applied to the template values.
For positions, we add ∆µk to the FLAME-tracked canon-
ical location ¯µk.
Thus the final parameters are µk =
¯µk+∆µk, sk = sT
k ·exp(∆sk), qk = normalize(qT
k +∆qk),
αk = σ(logit(αT
k ) + ∆αk), and ck = cT
k + ∆ck.
We implement the decoder with a shallow MLP. Gaus-
sian embeddings {ek} are initialized using sinusoidal po-
sitional encodings of their canonical FLAME coordinates,
and identity codes {wi}N
i=1 are initialized from a standard
Normal distribution. During decoder pretraining, we jointly
optimize hθ, {wi}, and {ek} using
Ldec = λ1LLPIPS + λ2L1 + λ3LSSIM
+ λ4L2(∆µ) + λ5L2(∆s),
(1)
computed between rendered predictions and ground-truth
images. LPIPS, SSIM, and L1 promote perceptual and pho-
tometric accuracy, while the L2 regularizers keep residuals
small and stable.
3.3.2. Encoder Design and Optimization
The encoder gϕ predicts a pose-invariant latent code for
the face depicted in I, from which the decoder can infer a
full 3DGS representation. We construct it as a composition
gϕ = gMLP ◦gFR, where gFR is a pretrained face recognition
backbone and gMLP is a lightweight projection network. The
face recognition model provides identity features that are in-
variant to viewpoint, while the projection MLP maps these
features to the latent space used by the decoder.
Given the precomputed identity codes {wi}N
i=1 learned
during decoder training, we train gϕ to map all images of
the same subject to their code. The encoder loss is
Lenc(w, ˆw) = L2(w, ˆw) + λcos Lcos(w, ˆw),
(2)
where ˆw = gϕ(I) is the predicted embedding and Lcos is the
cosine distance. This training strategy encourages the en-
coder to generalize to unseen identities and arbitrary poses.
3.4. Appearance Refinement at Inference Time
Given an input image I from an arbitrary viewpoint at in-
ference time, a single encoder–decoder pass first predicts
residuals that deform the canonical template, producing a
stable and 3D-consistent geometry anchored by the learned
prior. We then apply a lightweight refinement step that opti-
mizes only the latent code w and the decoder’s appearance
outputs for ∼300 iterations (∼3 seconds on an A100).
Crucially, unlike methods that directly optimize Gaussian
parameters from a single view [21, 52] – which can dis-
tort geometry and harm multi-view consistency – this re-
finement does not update Gaussian parameters explicitly.
Instead, all adjustments flow through the encoder–decoder
prior, ensuring that any changes remain consistent with
the learned canonical geometry and do not introduce view-
specific artifacts. Once reconstruction is complete, the re-
sulting Gaussians can be rendered in real time using stan-
dard 3DGS rasterization.
3.5. Animation and Reenactment
Our animation module follows the mesh-attached Gaus-
sian design introduced in the template construction stage
(Sec. 3.2), similar to GaussianAvatars [49]. Each Gaussian
is anchored to a FLAME face-center location (plus teeth an-
chors) and inherits fixed skinning weights {wk,j}J
j=1 from
the FLAME mesh.
Given target FLAME expression or pose parameters, we
obtain the joint transformations {Aj}J
j=1 and animate each
Gaussian using standard linear blend skinning (LBS). For
Gaussian k, the local canonical parameters (µ′
k, σ′
k, r′
k) are
mapped to global space via
(µanim
k
, σanim
k
, ranim
k
) = Tlocal→global
 (µ′
k, σ′
k, r′
k), Tk

,
where Tlocal→global denotes the standard SE(3)-based Gaus-
sian frame transform, and Tk = PJ
j=1 wk,jAj. This up-
dates position, rotation, and scale consistently with the
FLAME-driven deformation.
This procedure yields smooth expression and pose
changes without additional optimization, enabling real-time
reenactment once the 3DGS model is reconstructed.
4. Experiments & Results
We evaluated FastAvatar on single-view 3D face reconstruc-
tion using the Nersemble dataset [29], which contains 417
identities captured simultaneously from 16 calibrated view-
points spanning frontal to extreme profile poses. Each iden-
tity is recorded under multiple expressions. We used 410
identities for training and held out 7 identities for testing.
For training, we sampled 6 expressions per identity and as-
signed each identity–expression pair a distinct latent code.
Baselines.
We compare FastAvatar (base and full)
against recent state-of-the-art 3DGS and neural avatar
methods: (1) Optimization-driven: GaussianAvatars [49],
FlashAvatar [67];
(2) Feed-forward:
GAGAvatar [7],
LAM [21]; (3) Diffusion-based: Arc2Avatar [18], Diffu-
sionRig [13].
We use the official implementations and
recommended configurations for all methods.
Because
Arc2Avatar, GAGAvatar, and LAM operate in their own
canonical spaces, we estimate camera intrinsics and ex-
trinsics by PnP-aligning their reconstructed geometry to
5

<!-- page 6 -->
Ours (base)
Ours (full)
Arc2Avatar
FlashAvatar
GA
GT
Input
GAGAvatar
DiffusionRig
LAM
Figure 3. Qualitative comparison on single-image novel-view synthesis. Given a single arbitrary-view input (left), we compare Fas-
tAvatar (base and full) with DiffusionRig [13], GAGAvatar [7], LAM [21], Arc2Avatar [18], FlashAvatar [67], and GaussianAvatars
(GA) [49]. GAGAvatar and Arc2Avatar operate in their own canonical spaces; following prior work, we align their outputs to our coor-
dinate frame via PnP (details in Supplementary), though small residual shifts may remain. Diffusion-based and feed-forward baselines
struggle under large input poses, often producing blurry textures, synthetic-looking faces, or distorted geometry. GA and FlashAvatar,
which require multi-view fitting, degrade noticeably when extended to the single-view setting. In contrast, FastAvatar maintains coherent
geometry and identity across wide viewpoint changes; the full model further sharpens appearance through a lightweight 3-second refine-
ment stage. Additional examples, including more poses, expressions, and identity-similarity metrics, are provided in the Supplementary.
our canonical template (see Supplementary). Throughout
the experiments, Ours(base) denotes the feed-forward en-
coder–decoder prediction (geometry only), and Ours(full)
includes the subsequent appearance refinement.
Metrics.
We evaluate reconstruction accuracy using
PSNR, SSIM [64], LPIPS [76], and Identity Similarity [10].
For each test identity, we use one of the 16 views as the
input and evaluate rendering quality on the remaining 15
views, repeating this for all input viewpoints. All runtime
numbers are measured on a single NVIDIA A100 (40GB).
Implementation Details. We constructed the template
T from the 410 subject-specific 3DGS models optimized
for 7,000 iterations using all 16 views, each trained with
one randomly sampled expression. We used VHAP [48] to
extract FLAME parameters and camera poses. Following
GaussianAvatars, we place one Gaussian at the center of
each FLAME mesh face (9,976 faces) and add 168 Gaus-
sians for the upper and lower teeth, resulting in K = 10,144
mesh-attached Gaussians with consistent semantic corre-
spondence across all subjects. Please refer to Supplemen-
tary for additional implementation and training details.
6

<!-- page 7 -->
Table 1. Quantitative comparison on novel-view reconstruc-
tion. FastAvatar achieves the best performance across all metrics.
Methods marked with an asterisk (*) may have slightly underesti-
mated scores due to minor residual misalignment after PnP-based
canonical alignment.
Method
PSNR ↑
SSIM ↑
LPIPS ↓
ID Sim. ↑
DiffusionRig
14.21
0.70
0.29
0.65
GAGAvatar∗
15.83
0.73
0.33
0.76
Arc2Avatar∗
14.48
0.78
0.30
0.61
FlashAvatar
13.99
0.76
0.32
0.35
GaussianAvatars
16.39
0.79
0.30
0.39
LAM
14.13
0.81
0.34
0.77
Ours (base)
21.17
0.89
0.22
0.70
Ours (full)
24.01
0.91
0.19
0.81
4.1. Novel View Reconstruction Results
We first present qualitative comparisons in Fig. 3 for three
sample test cases. GAGAvatar, LAM, and DiffusionRig ex-
hibit strong degradation under non-frontal inputs, produc-
ing broken geometry, scattered points, or blurry outputs.
Arc2Avatar often yields synthetic facial textures and may
alter expressions (e.g., adding an open mouth). FlashAvatar
and GaussianAvatars (GA), which rely on multi-view op-
timization, struggle in the single-view setting and produce
noisy or incomplete reconstructions for challenging view-
points. These two methods can be viewed as refinement-
only analogs of our system: they optimize Gaussian pa-
rameters directly without a geometric prior, highlighting the
role of FastAvatar’s encoder–decoder stage in establishing
stable, 3D-consistent structure from a single image.
In contrast, FastAvatar delivers stable geometry and
consistent identity across all novel views.
The feed-
forward prediction (Ours(base)) already provides coherent
3D structure from a single input, while the refinement stage
(Ours(full)) further enhances appearance, capturing subtle
facial details, hair, and clothing with improved fidelity. To-
gether, these stages achieve high-quality novel-view synthe-
sis that remains accurate across large viewpoint changes.
Table 1 summarizes quantitative results for novel-view
reconstruction. Ours (full) achieves the best performance
across all metrics (24.01,dB PSNR, 0.91 SSIM, 0.19 LPIPS
and 0.81 ID similarity), substantially outperforming all
baselines. Ours (base) – the feed-forward encoder–decoder
prediction – already provides strong geometry (21.17 dB
PSNR, 0.89 SSIM) before the refinement phase.
4.2. Runtime Results
Fig. 4 presents the trade-off between reconstruction qual-
ity and fitting time for different methods. GAGAvatar and
LAM operate in (milli-)seconds but produce far lower ac-
curacy.
Diffusion-based (DiffusionRig, Arc2Avatar) and
optimization-driven (FlashAvatar, GaussianAvatars) meth-
10 ² 10 ¹
10
10¹
10²
10³
10
Runtime (seconds)
10.0
12.5
15.0
17.5
20.0
22.5
25.0
PSNR (dB)
PSNR
10 ² 10 ¹
10
10¹
10²
10³
10
Runtime (seconds)
0.65
0.70
0.75
0.80
0.85
0.90
0.95
SSIM
SSIM
DiffusionRig
GAGAvatar
Arc2Avatar
FlashAvatar
GaussianAvatars
LAM
Ours (base)
Ours (full)
Figure 4.
Reconstruction quality vs. runtime.
Ours (base)
produces strong feed-forward reconstructions (21.17 dB PSNR,
0.89 SSIM), while Ours (full) achieves state-of-the-art quality
(24.01 dB, 0.91 SSIM) with only ∼3 seconds of refinement.
Original
Self-reenactment
Cross-reenactment
Expr 1
Expr  2
Expr 3
Driven 1
Driven 2
Output1
Output2
Figure 5. Self- and cross-reenactment. Starting from a single re-
constructed face (left), FastAvatar can reproduce expressions from
the same subject (self) or transfer expressions from another subject
(cross) by driving the Gaussians with FLAME parameters. Iden-
tity remains stable while expressions are well reproduced.
ods require seconds-to-hours of per-subject optimization
while still trailing our method in accuracy.
Ours (full)
achieves the best overall reconstruction with only ∼3 sec-
onds of refinement, representing a substantially better qual-
ity–speed trade-off than all prior approaches. Ours (base)
runs in a single feed-forward pass and already reaches
strong accuracy, highlighting the efficiency and stability of
the encoder–decoder geometry prior.
4.3. Self- and Cross-Reenactment
Fig. 5 shows both self- and cross-reenactment results. In the
self-reenactment examples, we drive the reconstructed sub-
ject using FLAME expression parameters extracted from
other frames of the same identity. The outputs follow the
target expressions while maintaining the subject’s overall
geometry and appearance. In the cross-reenactment exam-
ples, we use FLAME parameters from a different “driver”
subject.
The transferred expressions are reproduced on
the source face without altering its identity, and the defor-
mations remain stable across different expressions. These
examples illustrate that the FLAME-guided deformation
model allows FastAvatar to reproduce a range of expres-
sions from a single reconstructed identity.
4.4. Out-Of-Distribution Identities
We further tested FastAvatar on identities outside of the
Nersemble dataset. We obtained the FLAME parameters for
7

<!-- page 8 -->
Figure 6. Generalization to out-of-distribution identities. Left
column = single input image. The remaining columns = novel-
view renderings from the reconstructed 3DGS model.
FastA-
vatar produces stable, identity-preserving reconstructions for un-
seen subjects and maintains consistent geometry across views.
these images using EMOCA [9], ensuring consistent align-
ment with our canonical template. As shown in Fig. 6, Fas-
tAvatar reconstructs clean, identity-preserving 3DGS mod-
els from a single image of OOD identities. We provide ad-
ditional OOD subjects and viewpoints in Supplementary.
4.5. Latent Space Structure and Decoder Analysis
We analyzed the latent space learned by the decoder to ver-
ify that it captures a smooth and generalizable representa-
tion rather than memorizing training identities. Fig. 7(left))
presents identity interpolation traversals between two la-
tent codes. The intermediate reconstructions vary smoothly
in geometry and appearance and remain consistent across
novel viewpoints, indicating a smooth latent space. We also
explored global attribute directions in the latent space (e.g.,
hair length, expression intensity). Traversing a code along
these directions produces coherent edits while preserving
identity and multi-view consistency (Fig. 7(middle, right)).
We provide the procedure for estimating these directions
and more results in Supplementary.
4.6. Ablation Studies
We finally present an ablation study of FastAvatar’s key
design choices in Table 2.
We first find that fewer
Gaussians (K=5023) lose detail, while a larger number
(K=40,000) improves fidelity but slows inference.
Our
default K=10144 strikes a balance.
Second, removing
SSIM (decoder) or cosine distance (encoder) consistently
degrades final rendering quality. Third, initialization with
the learned template model yields the most stable and ac-
curate reconstructions, outperforming joint-optimizing a
canonical template during decoder training or random ini-
tialization. Fourth, test-time refinement improves results,
though long runs (e.g., 600 steps) give diminishing returns
relative to the temporal cost. Full results, including visual
comparisons, are in Supplementary.
Table 2. Ablation results on FastAvatar design choices. All
results are reported for full version unless noted.
Setting
PSNR ↑
SSIM ↑
Runtime (ms)
Number of Gaussians K (Default: 10,144)
5023
20.94
0.84
9
40,000
25.58
0.93
29
Loss Weights (Default: Eq. (1)–(2))
w/o SSIM (dec.)
22.03
0.88
10
w/o CosSim (enc.)
22.27
0.89
10
Gaussian Init. (Default: Average Template)
Random Init
21.92
0.88
10
Joint-Opt.
22.84
0.89
10
Refinement Iterations (Default: 300)
0 (feed-forward)
21.17
0.89
10
600
24.32
0.91
6000
Ours (full)
24.01
0.91
3000
5. Discussion and Conclusion
FastAvatar provides a practical solution for single-image
3D face reconstruction across large pose variations. The
two-stage pipeline: an encoder–decoder feed-forward pre-
diction followed by a lightweight refinement, allows us
to recover clean geometry in one pass and improve ap-
pearance with only ∼3 seconds of additional computa-
tion. First, a key component of this design is the mesh-
attached average Gaussian template, which establishes sta-
ble semantic correspondences across subjects and makes
residual prediction well conditioned. Our ablation studies
confirm that this canonical parameterization is critical for
reliable geometry estimation and avoids the instability. The
encoder–decoder architecture further contributes to gener-
alization. By encouraging a pose-invariant latent represen-
tation during training, the model can handle a wide variety
of inputs and maintain identity consistency for unseen sub-
jects. Together, these components enable FastAvatar to pro-
duce high-quality reconstructions while keeping the overall
system simple and efficient.
Limitations. FastAvatar inherits structural constraints
from FLAME and the face-recognition backbone used by
the encoder. FLAME does not model long hair, fine strands,
or clothing, and most face-recognition models crop tightly
around the face. As a result, subjects with long hairstyles,
prominent bangs, hats, or high-variation clothing, espe-
cially common in female subjects, may exhibit smoothed or
incomplete reconstructions around these regions, we share
a failure case study in the Supplementary. These limitations
are shared by most current 3DGS-based avatar systems
and point toward the need for more expressive priors and
broader training data. In addition, the Nersemble dataset
itself has limited demographic and appearance diversity,
which constrains the range of identities and hairstyles that
current methods can reliably model.
Richer multi-view
8

<!-- page 9 -->
Expression
Neutral
Identity
ID1
ID2
Hair Length
Short
Long
Disgust
Figure 7. Latent space interpolation and attribute traversals. Left: Identity interpolation between two codes produces smooth, realistic
transitions in geometry and appearance. Middle and Right: Moving along learned attribute directions (e.g., hair length, expression
intensity) yields consistent edits across views while preserving identity, illustrating that the decoder has learned a meaningful latent space.
datasets would help explore the full capabilities and limi-
tations of single-image 3DGS reconstruction in this space.
9

<!-- page 10 -->
References
[1] Sizhe An, Hongyi Xu, Yichun Shi, Guoxian Song, Umit Y
Ogras, and Linjie Luo. Panohead: Geometry-aware 3d full-
head synthesis in 360deg. In Proceedings of the IEEE/CVF
conference on computer vision and pattern recognition,
pages 20950–20959, 2023. 3
[2] Volker Blanz and Thomas Vetter. Face recognition based on
fitting a 3d morphable model. IEEE Transactions on pattern
analysis and machine intelligence, 25(9):1063–1074, 2003.
2
[3] Volker Blanz and Thomas Vetter. A morphable model for the
synthesis of 3d faces. In Seminal Graphics Papers: Pushing
the Boundaries, Volume 2, pages 157–164. 2023. 2, 4
[4] Marcel C. Buehler, Gengyan Li, Erroll Wood, Leonhard
Helminger, Xu Chen, Tanmay Shah, Daoye Wang, Stephan
Garbin, Sergio Orts-Escolano, Otmar Hilliges, Dmitry La-
gun, J´er´emy Riviere, Paulo Gotardo, Thabo Beeler, Abhim-
itra Meka, and Kripasindhu Sarkar.
Cafca: High-quality
novel view synthesis of expressive faces from casual few-
shot captures. In ACM SIGGRAPH Asia 2024 Conference
Paper. 2024. 3
[5] Eric R Chan, Connor Z Lin, Matthew A Chan, Koki Nagano,
Boxiao Pan, Shalini De Mello, Orazio Gallo, Leonidas J
Guibas, Jonathan Tremblay, Sameh Khamis, et al. Efficient
geometry-aware 3d generative adversarial networks. In Pro-
ceedings of the IEEE/CVF conference on computer vision
and pattern recognition, pages 16123–16133, 2022. 2, 3
[6] Zhuowei Chen, Shancheng Fang, Wei Liu, Qian He, Mengqi
Huang, and Zhendong Mao. Dreamidentity: Enhanced ed-
itability for efficient face-identity preserved image genera-
tion. In Proceedings of the AAAI Conference on Artificial
Intelligence, pages 1281–1289, 2024. 3
[7] Xuangeng Chu and Tatsuya Harada. Generalizable and ani-
matable gaussian head avatar. Advances in Neural Informa-
tion Processing Systems, 37:57642–57670, 2024. 2, 3, 5, 6
[8] Xuangeng Chu, Yu Li, Ailing Zeng, Tianyu Yang, Lijian
Lin, Yunfei Liu, and Tatsuya Harada. Gpavatar: Generaliz-
able and precise head avatar from image (s). arXiv preprint
arXiv:2401.10215, 2024. 3
[9] Radek Danˇeˇcek, Michael J Black, and Timo Bolkart. Emoca:
Emotion driven monocular face capture and animation. In
Proceedings of the IEEE/CVF Conference on Computer Vi-
sion and Pattern Recognition, pages 20311–20322, 2022. 3,
8
[10] Jiankang Deng, Jia Guo, Xue Niannan, and Stefanos
Zafeiriou. Arcface: Additive angular margin loss for deep
face recognition. In CVPR, 2019. 2, 6
[11] Yu Deng, Duomin Wang, Xiaohang Ren, Xingyu Chen, and
Baoyuan Wang.
Portrait4d: Learning one-shot 4d head
avatar synthesis using synthetic data.
In Proceedings of
the IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 7119–7130, 2024. 3
[12] Helisa Dhamo, Yinyu Nie, Arthur Moreau, Jifei Song,
Richard Shaw, Yiren Zhou, and Eduardo P´erez-Pellitero.
Headgas: Real-time animatable head avatars via 3d gaus-
sian splatting. In European Conference on Computer Vision,
pages 459–476. Springer, 2024. 3
[13] Zheng Ding, Cecilia Zhang, Zhihao Xia, Lars Jebe, Zhuowen
Tu, and Xiuming Zhang. Diffusionrig: Learning personal-
ized priors for facial appearance editing. In Proceedings of
the IEEE/CVF Conference on Computer Vision and Pattern
Recognition, 2023. 2, 5, 6
[14] Jiemin Fang, Taoran Yi, Xinggang Wang, Lingxi Xie, Xi-
aopeng Zhang, Wenyu Liu, Matthias Nießner, and Qi Tian.
Fast dynamic radiance fields with time-aware neural vox-
els. In SIGGRAPH Asia 2022 Conference Papers, pages 1–9,
2022. 3
[15] Yao Feng, Haiwen Feng, Michael J Black, and Timo Bolkart.
Learning an animatable detailed 3d face model from in-the-
wild images. ACM Transactions on Graphics (ToG), 40(4):
1–13, 2021. 3
[16] Guy Gafni, Justus Thies, Michael Zollhofer, and Matthias
Nießner. Dynamic neural radiance fields for monocular 4d
facial avatar reconstruction. In Proceedings of the IEEE/CVF
Conference on Computer Vision and Pattern Recognition,
pages 8649–8658, 2021. 3
[17] Baris
Gecer,
Alexandros
Lattas,
Stylianos
Ploumpis,
Jiankang
Deng,
Athanasios
Papaioannou,
Stylianos
Moschoglou, and Stefanos Zafeiriou. Synthesizing coupled
3d face modalities by trunk-branch generative adversarial
networks.
In European conference on computer vision,
pages 415–433. Springer, 2020. 3
[18] Dimitrios
Gerogiannis,
Foivos
Paraperas
Papantoniou,
Rolandos Alexandros Potamias, Alexandros Lattas, and Ste-
fanos Zafeiriou.
Arc2avatar:
Generating expressive 3d
avatars from a single image via id guidance. In Proceedings
of the Computer Vision and Pattern Recognition Conference,
pages 10770–10782, 2025. 2, 3, 5, 6
[19] Simon Giebenhain, Tobias Kirschstein, Martin R¨unz, Lour-
des Agapito, and Matthias Nießner. Npga: Neural paramet-
ric gaussian avatars. In SIGGRAPH Asia 2024 Conference
Papers (SA Conference Papers ’24), December 3-6, Tokyo,
Japan, 2024. 3
[20] Ian J Goodfellow, Jean Pouget-Abadie, Mehdi Mirza, Bing
Xu, David Warde-Farley, Sherjil Ozair, Aaron Courville, and
Yoshua Bengio. Generative adversarial nets. Advances in
neural information processing systems, 27, 2014. 2
[21] Yisheng He, Xiaodong Gu, Xiaodan Ye, Chao Xu, Zhengyi
Zhao, Yuan Dong, Weihao Yuan, Zilong Dong, and Liefeng
Bo. Lam: Large avatar model for one-shot animatable gaus-
sian head. In Proceedings of the Special Interest Group on
Computer Graphics and Interactive Techniques Conference
Conference Papers, pages 1–13, 2025. 2, 3, 5, 6
[22] Jonathan Ho, Ajay Jain, and Pieter Abbeel. Denoising dif-
fusion probabilistic models. Advances in neural information
processing systems, 33:6840–6851, 2020. 2
[23] Yang Hong, Bo Peng, Haiyao Xiao, Ligang Liu, and Juy-
ong Zhang.
Headnerf: A real-time nerf-based parametric
head model. In Proceedings of the IEEE/CVF Conference
on Computer Vision and Pattern Recognition, pages 20374–
20384, 2022. 3
[24] Liangxiao Hu, Hongwen Zhang, Yuxiang Zhang, Boyao
Zhou, Boning Liu, Shengping Zhang, and Liqiang Nie.
Gaussianavatar: Towards realistic human avatar modeling
10

<!-- page 11 -->
from a single video via animatable 3d gaussians. In Pro-
ceedings of the IEEE/CVF conference on computer vision
and pattern recognition, pages 634–644, 2024. 3
[25] Tero Karras, Samuli Laine, and Timo Aila. A style-based
generator architecture for generative adversarial networks.
In Proceedings of the IEEE/CVF conference on computer vi-
sion and pattern recognition, pages 4401–4410, 2019. 3
[26] Tero Karras, Samuli Laine, Miika Aittala, Janne Hellsten,
Jaakko Lehtinen, and Timo Aila.
Analyzing and improv-
ing the image quality of stylegan.
In Proceedings of
the IEEE/CVF conference on computer vision and pattern
recognition, pages 8110–8119, 2020. 3
[27] Bernhard Kerbl, Georgios Kopanas, Thomas Leimk¨uhler,
and George Drettakis.
3d gaussian splatting for real-time
radiance field rendering. ACM Trans. Graph., 42(4):139–1,
2023. 2, 3
[28] Taekyung Ki, Dongchan Min, and Gyeongsu Chae. Learn-
ing to generate conditional tri-plane for 3d-aware expression
controllable portrait animation. In European Conference on
Computer Vision, pages 476–493. Springer, 2024. 3
[29] Tobias Kirschstein, Shenhan Qian, Simon Giebenhain, Tim
Walter, and Matthias Nießner. Nersemble: Multi-view ra-
diance field reconstruction of human heads.
ACM Trans.
Graph., 42(4), 2023. 2, 5
[30] Muhammed Kocabas, Jen-Hao Rick Chang, James Gabriel,
Oncel Tuzel, and Anurag Ranjan. Hugs: Human gaussian
splats. In Proceedings of the IEEE/CVF conference on com-
puter vision and pattern recognition, pages 505–515, 2024.
3
[31] Alexandros
Lattas,
Stylianos
Moschoglou,
Stylianos
Ploumpis,
Baris Gecer,
Jiankang Deng,
and Stefanos
Zafeiriou.
Fitme:
Deep photorealistic 3d morphable
model avatars.
In Proceedings of the IEEE/CVF Confer-
ence on Computer Vision and Pattern Recognition, pages
8629–8640, 2023. 3
[32] Jiahe Li, Jiawei Zhang, Xiao Bai, Jin Zheng, Xin Ning, Jun
Zhou, and Lin Gu. Talkinggaussian: Structure-persistent 3d
talking head synthesis via gaussian splatting. In European
Conference on Computer Vision, pages 127–145. Springer,
2024. 3
[33] Ruilong Li, Karl Bladin, Yajie Zhao, Chinmay Chinara,
Owen Ingraham, Pengda Xiang, Xinglei Ren, Pratusha
Prasad, Bipin Kishore, Jun Xing, et al.
Learning forma-
tion of physically-based face attributes. In Proceedings of
the IEEE/CVF conference on computer vision and pattern
recognition, pages 3410–3419, 2020. 2
[34] Tianye Li, Timo Bolkart, Michael. J. Black, Hao Li, and
Javier Romero. Learning a model of facial shape and ex-
pression from 4D scans. ACM Transactions on Graphics,
(Proc. SIGGRAPH Asia), 36(6):194:1–194:17, 2017. 2, 4
[35] Weichuang Li, Longhao Zhang, Dong Wang, Bin Zhao, Zhi-
gang Wang, Mulin Chen, Bang Zhang, Zhongjian Wang,
Liefeng Bo, and Xuelong Li. One-shot high-fidelity talking-
head synthesis with deformable neural radiance field. In Pro-
ceedings of the IEEE/CVF Conference on Computer Vision
and Pattern Recognition, pages 17969–17978, 2023. 3
[36] Xueting Li, Shalini De Mello, Sifei Liu, Koki Nagano, Umar
Iqbal, and Jan Kautz. Generalizable one-shot 3d neural head
avatar. Advances in Neural Information Processing Systems,
36:47239–47250, 2023. 3
[37] Zhengqi Li, Simon Niklaus, Noah Snavely, and Oliver Wang.
Neural scene flow fields for space-time view synthesis of dy-
namic scenes. In Proceedings of the IEEE/CVF conference
on computer vision and pattern recognition, pages 6498–
6508, 2021. 3
[38] Isabella Liu, Hao Su, and Xiaolong Wang. Dynamic gaus-
sians mesh: Consistent mesh reconstruction from dynamic
scenes. arXiv preprint arXiv:2404.12379, 2024. 2, 4
[39] Haoyu Ma, Tong Zhang, Shanlin Sun, Xiangyi Yan, Kun
Han, and Xiaohui Xie. Cvthead: One-shot controllable head
avatar with vertex-feature transformer. In Proceedings of the
IEEE/CVF Winter Conference on Applications of Computer
Vision, pages 6131–6141, 2024. 3
[40] Jian Ma, Junhao Liang, Chen Chen, and Haonan Lu. Subject-
diffusion: Open domain personalized text-to-image genera-
tion without test-time fine-tuning. In ACM SIGGRAPH 2024
Conference Papers, pages 1–12, 2024. 3
[41] Shengjie Ma, Yanlin Weng, Tianjia Shao, and Kun Zhou. 3d
gaussian blendshapes for head avatar animation.
In ACM
SIGGRAPH 2024 Conference Papers, pages 1–10, 2024. 3
[42] Zhiyuan Ma, Xiangyu Zhu, Guo-Jun Qi, Zhen Lei, and Lei
Zhang. Otavatar: One-shot talking face avatar with control-
lable tri-plane rendering. In Proceedings of the IEEE/CVF
Conference on Computer Vision and Pattern Recognition,
pages 16901–16910, 2023. 3
[43] Ben Mildenhall, Pratul P Srinivasan, Matthew Tancik,
Jonathan T Barron, Ravi Ramamoorthi, and Ren Ng. Nerf:
Representing scenes as neural radiance fields for view syn-
thesis. Communications of the ACM, 65(1):99–106, 2021. 2,
3
[44] Foivos Paraperas Papantoniou, Alexandros Lattas, Stylianos
Moschoglou, Jiankang Deng, Bernhard Kainz, and Stefanos
Zafeiriou. Arc2face: A foundation model for id-consistent
human faces. In Proceedings of the European Conference on
Computer Vision (ECCV), 2024. 3
[45] Keunhong Park, Utkarsh Sinha, Jonathan T Barron, Sofien
Bouaziz, Dan B Goldman, Steven M Seitz, and Ricardo
Martin-Brualla. Nerfies: Deformable neural radiance fields.
In Proceedings of the IEEE/CVF international conference on
computer vision, pages 5865–5874, 2021. 3
[46] Keunhong Park, Utkarsh Sinha, Peter Hedman, Jonathan T
Barron, Sofien Bouaziz, Dan B Goldman, Ricardo Martin-
Brualla, and Steven M Seitz.
Hypernerf:
A higher-
dimensional representation for topologically varying neural
radiance fields. arXiv preprint arXiv:2106.13228, 2021. 3
[47] Albert Pumarola, Enric Corona, Gerard Pons-Moll, and
Francesc Moreno-Noguer.
D-nerf: Neural radiance fields
for dynamic scenes. In Proceedings of the IEEE/CVF con-
ference on computer vision and pattern recognition, pages
10318–10327, 2021. 3
[48] Shenhan Qian. Vhap: Versatile head alignment with adaptive
appearance priors, 2024. 6
[49] Shenhan Qian, Tobias Kirschstein, Liam Schoneveld, Davide
Davoli, Simon Giebenhain, and Matthias Nießner.
Gaus-
sianavatars: Photorealistic head avatars with rigged 3d gaus-
11

<!-- page 12 -->
sians. In Proceedings of the IEEE/CVF Conference on Com-
puter Vision and Pattern Recognition, pages 20299–20309,
2024. 2, 3, 4, 5, 6
[50] Zhiyin Qian, Shaofei Wang, Marko Mihajlovic, Andreas
Geiger, and Siyu Tang.
3dgs-avatar: Animatable avatars
via deformable 3d gaussian splatting.
In Proceedings of
the IEEE/CVF conference on computer vision and pattern
recognition, pages 5020–5030, 2024.
[51] Alec Radford, Jong Wook Kim, Chris Hallacy, Aditya
Ramesh, Gabriel Goh, Sandhini Agarwal, Girish Sastry,
Amanda Askell, Pamela Mishkin, Jack Clark, et al. Learning
transferable visual models from natural language supervi-
sion. In International conference on machine learning, pages
8748–8763. PmLR, 2021.
[52] Jack Saunders, Charlie Hewitt, Yanan Jian, Marek Kowal-
ski, Tadas Baltrusaitis, Yiye Chen, Darren Cosker, Virginia
Estellers, Nicholas Gyd´e, Vinay P Namboodiri, et al. Gasp:
Gaussian avatars with synthetic priors. In Proceedings of the
Computer Vision and Pattern Recognition Conference, pages
271–280, 2025. 2, 4, 5
[53] Zhijing Shao, Zhaolong Wang, Zhuang Li, Duotun Wang,
Xiangru Lin, Yu Zhang, Mingming Fan, and Zeyu Wang.
Splattingavatar:
Realistic real-time human avatars with
mesh-embedded gaussian splatting. In Proceedings of the
IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 1606–1616, 2024. 3
[54] Jing Shi, Wei Xiong, Zhe Lin, and Hyun Joon Jung.
In-
stantbooth: Personalized text-to-image generation without
test-time finetuning. In Proceedings of the IEEE/CVF con-
ference on computer vision and pattern recognition, pages
8543–8552, 2024. 3
[55] Kaede Shiohara and Toshihiko Yamasaki.
Face2diffusion
for fast and editable face personalization. In Proceedings of
the IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 6850–6859, 2024. 3
[56] William AP Smith, Alassane Seck, Hannah Dee, Bernard
Tiddeman, Joshua B Tenenbaum, and Bernhard Egger. A
morphable face albedo model.
In Proceedings of the
IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 5011–5020, 2020. 2
[57] Jingxiang Sun, Xuan Wang, Lizhen Wang, Xiaoyu Li, Yong
Zhang, Hongwen Zhang, and Yebin Liu. Next3d: Gener-
ative neural texture rasterization for 3d-aware head avatars.
In Proceedings of the IEEE/CVF conference on computer vi-
sion and pattern recognition, pages 20991–21002, 2023. 3
[58] Felix Taubner, Ruihang Zhang, Mathieu Tuli, and David B
Lindell. Cap4d: Creating animatable 4d portrait avatars with
morphable multi-view diffusion models. In Proceedings of
the Computer Vision and Pattern Recognition Conference,
pages 5318–5330, 2025. 3
[59] Phong Tran, Egor Zakharov, Long-Nhat Ho, Anh Tuan Tran,
Liwen Hu, and Hao Li. Voodoo 3d: Volumetric portrait dis-
entanglement for one-shot 3d head reenactment. In Proceed-
ings of the IEEE/CVF Conference on Computer Vision and
Pattern Recognition, pages 10336–10348, 2024. 3
[60] Edgar Tretschk, Ayush Tewari, Vladislav Golyanik, Michael
Zollh¨ofer, Christoph Lassner, and Christian Theobalt. Non-
rigid neural radiance fields: Reconstruction and novel view
synthesis of a dynamic scene from monocular video. In Pro-
ceedings of the IEEE/CVF international conference on com-
puter vision, pages 12959–12970, 2021. 3
[61] Alex Trevithick, Matthew Chan, Michael Stengel, Eric Chan,
Chao Liu, Zhiding Yu, Sameh Khamis, Manmohan Chan-
draker, Ravi Ramamoorthi, and Koki Nagano. Real-time ra-
diance fields for single-image portrait view synthesis. ACM
Transactions on Graphics (TOG), 42(4):1–15, 2023. 3
[62] Cong Wang, Di Kang, Heyi Sun, Shenhan Qian, Zixuan
Wang, Linchao Bao, and Song-Hai Zhang. Mega: Hybrid
mesh-gaussian head avatar for high-fidelity rendering and
head editing. In Proceedings of the Computer Vision and
Pattern Recognition Conference, pages 26274–26284, 2025.
3
[63] Shengze Wang, Xueting Li, Chao Liu, Matthew Chan,
Michael Stengel, Henry Fuchs, Shalini De Mello, and Koki
Nagano. Coherent 3d portrait video reconstruction via tri-
plane fusion. In Proceedings of the IEEE/CVF Conference
on Computer Vision and Pattern Recognition (CVPR), pages
10712–10722, 2025. 3
[64] Zhou Wang, Alan C Bovik, Hamid R Sheikh, and Eero P Si-
moncelli. Image quality assessment: from error visibility to
structural similarity. IEEE transactions on image processing,
13(4):600–612, 2004. 6
[65] Xiaobao Wei, Peng Chen, Ming Lu, Hui Chen, and Feng
Tian.
Graphavatar:
Compact head avatars with gnn-
generated 3d gaussians. In Proceedings of the AAAI Con-
ference on Artificial Intelligence, pages 8295–8303, 2025. 3
[66] Yuxiang Wei, Yabo Zhang, Zhilong Ji, Jinfeng Bai, Lei
Zhang, and Wangmeng Zuo. Elite: Encoding visual con-
cepts into textual embeddings for customized text-to-image
generation. In Proceedings of the IEEE/CVF International
Conference on Computer Vision, pages 15943–15953, 2023.
3
[67] Jun Xiang, Xuan Gao, Yudong Guo, and Juyong Zhang.
Flashavatar: High-fidelity head avatar with efficient gaussian
embedding.
In Proceedings of the IEEE/CVF Conference
on Computer Vision and Pattern Recognition, pages 1802–
1812, 2024. 2, 3, 5, 6
[68] Guangxuan Xiao, Tianwei Yin, William T Freeman, Fr´edo
Durand, and Song Han. Fastcomposer: Tuning-free multi-
subject image generation with localized attention. Interna-
tional Journal of Computer Vision, 133(3):1175–1194, 2025.
3
[69] Yuelang Xu, Benwang Chen, Zhe Li, Hongwen Zhang,
Lizhen Wang, Zerong Zheng, and Yebin Liu. Gaussian head
avatar: Ultra high-fidelity head avatar via dynamic gaussians.
In Proceedings of the IEEE/CVF conference on computer vi-
sion and pattern recognition, pages 1931–1941, 2024. 3
[70] Yuelang Xu, Lizhen Wang, Zerong Zheng, Zhaoqi Su, and
Yebin Liu. 3d gaussian parametric head model. In European
Conference on Computer Vision, pages 129–147. Springer,
2024. 3
[71] Peizhi Yan, Rabab Ward, Qiang Tang, and Shan Du. Gaus-
sian deja-vu: Creating controllable 3d gaussian head-avatars
with enhanced generalization and personalization abilities.
In Proceedings of the Winter Conference on Applications of
Computer Vision (WACV), pages 276–286, 2025. 2, 3, 4
12

<!-- page 13 -->
[72] Haotian Yang, Hao Zhu, Yanru Wang, Mingkai Huang, Qiu
Shen, Ruigang Yang, and Xun Cao. Facescape: a large-scale
high quality 3d face dataset and detailed riggable 3d face pre-
diction. In Proceedings of the ieee/cvf conference on com-
puter vision and pattern recognition, pages 601–610, 2020.
3
[73] Songlin Yang, Wei Wang, Yushi Lan, Xiangyu Fan, Bo
Peng, Lei Yang, and Jing Dong. Learning dense correspon-
dence for nerf-based face reenactment. In Proceedings of
the AAAI Conference on Artificial Intelligence, pages 6522–
6530, 2024. 3
[74] Vickie Ye, Ruilong Li, Justin Kerr, Matias Turkulainen,
Brent Yi, Zhuoyang Pan, Otto Seiskari, Jianbo Ye, Jeffrey
Hu, Matthew Tancik, and Angjoo Kanazawa.
gsplat: An
open-source library for gaussian splatting. Journal of Ma-
chine Learning Research, 26(34):1–17, 2025. 4
[75] Zhenhui Ye, Tianyun Zhong, Yi Ren, Jiaqi Yang, Weichuang
Li, Jiawei Huang, Ziyue Jiang, Jinzheng He, Rongjie Huang,
Jinglin Liu, et al.
Real3d-portrait: One-shot realistic 3d
talking portrait synthesis. arXiv preprint arXiv:2401.08503,
2024. 3
[76] Richard Zhang, Phillip Isola, Alexei A Efros, Eli Shecht-
man, and Oliver Wang. The unreasonable effectiveness of
deep features as a perceptual metric. In Proceedings of the
IEEE conference on computer vision and pattern recogni-
tion, pages 586–595, 2018. 6
[77] Xiaochen Zhao, Jingxiang Sun, Lizhen Wang, Jinli Suo, and
Yebin Liu. Invertavatar: Incremental gan inversion for gen-
eralized head avatars. In ACM SIGGRAPH 2024 Conference
Papers, pages 1–10, 2024. 3
[78] Yufeng Zheng, Wang Yifan, Gordon Wetzstein, Michael J
Black, and Otmar Hilliges.
Pointavatar:
Deformable
point-based head avatars from videos.
In Proceedings of
the IEEE/CVF conference on computer vision and pattern
recognition, pages 21057–21067, 2023. 3
[79] Yiyu Zhuang, Hao Zhu, Xusen Sun, and Xun Cao. Mofanerf:
Morphable facial neural radiance field. In European confer-
ence on computer vision, pages 268–285. Springer, 2022. 3
[80] Wojciech Zielonka, Timo Bolkart, and Justus Thies. Towards
metrical reconstruction of human faces. In European confer-
ence on computer vision, pages 250–269. Springer, 2022. 3
13
