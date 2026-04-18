<!-- page 1 -->
ArchitectHead: Continuous Level of Detail Control for 3D Gaussian Head
Avatars
Peizhi Yan1, Rabab Ward1, Qiang Tang, Shan Du3*
1University of British Columbia {yanpz, rababw}@ece.ubc.ca
3University of British Columbia (Okanagan) shan.du@ubc.ca
LOD = 0.0
LOD = 0.25
LOD = 0.50
LOD = 0.75
LOD = 1.00
45,876 Gaussians
141 FPS
30,253 Gaussians
182 FPS
17,855 Gaussians
222 FPS
8,788 Gaussians
255 FPS
2,829 Gaussians
276 FPS
High Efficiency, Low Quality
Low Efficiency, High Quality
Real-time, Continuous LOD Control
Figure 1. ArchitectHead supports continuous LOD control ranging from 0 (highest) to 1.0 (lowest). This figure shows the rendered image
quality under different LOD settings. For each case, we provide a zoom-in view of selected regions. We recommend viewing the figure on
a digital device with zoom for better inspection. The grey dots indicate the positions of the 3D Gaussian points. The test identity is taken
from the NeRFace dataset [7]. Red arrow indicates visible artifacts (sparse Gaussians) in the lowest LOD.
Abstract
3D Gaussian Splatting (3DGS) has enabled photorealis-
tic and real-time rendering of 3D head avatars. Existing
3DGS-based avatars typically rely on tens of thousands of
3D Gaussian points (Gaussians), with the number of Gaus-
sians fixed after training. However, many practical appli-
cations require adjustable levels of detail (LOD) to balance
rendering efficiency and visual quality. In this work, we
propose “ArchitectHead”, the first framework for creating
3D Gaussian head avatars that support continuous con-
trol over LOD. Our key idea is to parameterize the Gaus-
sians in a 2D UV feature space and propose a UV feature
field composed of multi-level learnable feature maps to en-
code their latent features. A lightweight neural network-
based decoder then transforms these latent features into 3D
Gaussian attributes for rendering. ArchitectHead controls
the number of Gaussians by dynamically resampling fea-
*Corresponding author: Shan Du.
ture maps from the UV feature field at the desired resolu-
tions. This method enables efficient and continuous con-
trol of LOD without retraining. Experimental results show
that ArchitectHead achieves state-of-the-art (SOTA) quality
in self and cross-identity reenactment tasks at the highest
LOD, while maintaining near SOTA performance at lower
LODs. At the lowest LOD, our method uses only 6.2% of the
Gaussians while the quality degrades moderately (L1 Loss
+7.9%, PSNR –0.97%, SSIM –0.6%, LPIPS Loss +24.1%),
and the rendering speed nearly doubles. The code will be
released. Project homepage: https://peizhiyan.
github.io/docs/architect/.
1. Introduction
3D head avatars are an important component of digital hu-
mans, with applications ranging from VR, telepresence,
video gaming, to video conferencing.
While recent ad-
vancements in 3D Gaussian Splatting (3DGS) [16] have
achieved a higher degree of photorealism than traditional
arXiv:2510.05488v1  [cs.CV]  7 Oct 2025

<!-- page 2 -->
mesh-based methods, they are more computationally inten-
sive and struggle to maintain real-time performance when
multiple avatars are rendered simultaneously [20, 27, 32,
43, 47]. In computer graphics, level of detail (LOD) tech-
niques for 3D meshes are widely used to balance visual
quality and efficiency [12].
However, applying LOD to
3DGS is challenging due to the unstructured nature of Gaus-
sian point clouds and the need for dynamic animation in
head avatars. To address this gap, we propose “Architect-
Head”, a framework that learns 3D Gaussian head avatars
from monocular videos and allows LOD adjustment after
training. Unlike conventional LOD methods that provide
only a few discrete levels (typically 3 to 4 levels) [4, 30],
ArchitectHead supports continuous LOD control, making it
easier to balance rendering speed and visual quality.
LOD methods are used to simplify 3D object geometries
to improve rendering efficiency and save computational re-
sources. For example, distant or less important parts of a
3D scene can be rendered with reduced geometric detail. In
general, there are three types of LOD methods: (1) discrete,
(2) continuous, and (3) view-dependent [11]. The discrete
LOD method creates a small set of simplified versions of the
same 3D model offline, which is easy to implement but of-
ten causes unsmooth visual effects when switching between
levels [4, 30]. Continuous LOD methods allow progressive
adjustment of LOD at run time, which leads to smoother
transitions and better use of resources [12, 36].
View-
dependent LOD further adapts the level of detail based on
the viewing position, allocating higher detail to visible or
important regions of a model [29]. In this work, our fo-
cus is to bring the advantages of continuous LOD into 3D
Gaussian head avatars, where smooth and flexible control
over level of detail is essential.
3D Gaussian head avatars represent the head using Gaus-
sian points, which are rendered with the 3DGS rasteriza-
tion method [16] to produce photorealistic images. Since
head avatars must be animatable, existing methods typically
bind the 3D Gaussians to a mesh-based head model to pro-
vide controllability. Two major binding strategies have been
explored. The first associates Gaussians with the triangle
facets of the mesh, so that transformations applied to the
facets are directly propagated to the corresponding Gaus-
sians [20, 27, 37, 50]. The second uses a 2D UV map as
an intermediate representation to connect the mesh geome-
try with the Gaussians. In this case, the mesh geometry is
first rasterized onto a UV map with predefined 2D-3D cor-
respondences, where each pixel encodes the 3D location of
the mesh surface, and these locations are then used to ini-
tialize the Gaussian positions [19, 34, 43, 44, 48]. We fol-
low the second strategy in designing ArchitectHead, as the
UV map provides an inherent 2D representation in which
nearby Gaussian points are also neighbors in UV space.
This property makes it natural to control the number of
Gaussians by adjusting the resolution of the UV map.
Although the UV-based strategy provides a natural way
to control the number of Gaussians through the UV map res-
olution, there are two remaining challenges. First, the UV
position map alone does not capture sufficient local infor-
mation to represent detailed 3D head appearance. Second,
it is necessary to balance different resolutions while main-
taining smooth transitions across LODs. These challenges
motivate our design of “ArchitectHead” in this work.
ArchitectHead is the first head avatar creation frame-
work that supports continuous adjustment of the level of
detail. We formulate continuous LOD control as resam-
pling from the 2D UV feature space. The key idea is to
make controlling the number of Gaussians in a head avatar
as simple as resizing a 2D image. To achieve this, we de-
sign a learnable multi-level UV feature field, structured as
a pyramid of UV-anchored feature maps at different resolu-
tions. The feature maps store the per-Gaussian latent fea-
tures, which will be learned during training. Our model is
trained per-person following the training objective of exist-
ing monocular head avatar works to gain better personaliza-
tion [2, 3, 20, 43]. After training, we can sample a UV fea-
ture map of any resolution between the maximum and mini-
mum levels to achieve run-time LOD control. Our sampling
strategy assigns higher weights to feature maps with resolu-
tions closer to the desired one to blend the UV feature maps
of different resolutions. This weighted blending method en-
sures smooth transitions across LODs. The sampled fea-
tures are concatenated with positionally encoded point lo-
cations, the expression code, and the LOD value to form
the latent representation of the Gaussian points. We employ
a lightweight neural decoder to convert these latent features
into 3D Gaussian attributes, ready for rendering.
The training has two stages. In the first stage, we train
with the highest LOD (LOD 0) to capture fine details and
stabilize learning. In the second stage, we randomly sample
LOD values between 0.0 and 1.0 so the decoder can adapt to
different levels of detail. This design enables efficient and
flexible LOD control for 3D Gaussian head avatars without
the need for retraining. Figure 1 shows an example of our
reconstructed head avatar with different LOD settings.
In summary, our main contributions are:
1. We propose ArchitectHead, a novel framework for cre-
ating 3D Gaussian head avatars that support on-the-fly
control of LOD without re-training. To our knowledge,
this is the first 3D Gaussian head avatar method that en-
ables real-time continuous LOD adjustment, providing
greater scalability for balancing rendering quality and ef-
ficiency across applications.
2. We introduce a learnable multi-level UV feature field
along with an adaptive sampling strategy to capture spa-
tial information across high to low resolutions. This en-
sures smooth transitions between different LODs.

<!-- page 3 -->
3. We conduct extensive experiments on monocular video
datasets for 3D head avatar reconstruction, demonstrat-
ing that ArchitectHead achieves effective and scalable
control of LOD while maintaining photorealistic quality.
2. Related Works
2.1. 3D Head Avatars
Existing 3D head avatar methods can be categorized by their
3D representation. Mesh-based methods are the most tradi-
tional, known for their rendering efficiency [5, 13, 23]. A
notable example is the 3D Morphable Models (3DMMs),
which are created by registering real 3D face scans to a tem-
plate mesh [1, 5, 21]. While 3DMMs provide disentangled
identity and expression representations, they are less effec-
tive at modeling non-rigid facial features like hair. Neural
radiance field (NeRF)-based methods [25] use neural net-
works to learn latent 3D representations and render images
by sampling points in 3D space, estimating transmittance,
and accumulating through volume rendering [35, 39, 40].
These methods support learning from images and videos
and can achieve photorealistic results. However, they are
computationally intensive due to the need for extensive
point sampling per frame and are less accurate with ge-
ometry. Point-based methods explicitly represent the head
with 3D points, allowing faster rendering and more flexibil-
ity than mesh-based approaches [2, 20, 27, 51]. Among the
point-based methods, 3D Gaussian splatting-based methods
have recently become the most popular, which we will de-
tail in the following subsection.
2.2. 3D Gaussian-based Head Avatars
3D Gaussian Splatting (3DGS) [16] has emerged as an effi-
cient and photorealistic representation for 3D head avatars,
capable of real-time rendering. To enable reconstruction
and animation, many works bind Gaussians to a 3DMM-
based prior such as FLAME [21]. This can be done by
rigging them to mesh triangles [20, 27, 50] or initializing
them via UV maps [19, 34, 43, 44]. Several methods fur-
ther improve expressiveness through neural decoders or ex-
pression blendshapes, enabling more controllable facial dy-
namics [3, 20, 24, 41, 44]. Another research direction fo-
cuses on generalization, using large-scale prior models for
few-shot or single-image personalization [10, 17, 19, 50].
Diffusion-based frameworks have also been explored to im-
prove monocular video supervision and robustness to novel
views [8, 37, 38]. Despite these advancements, a common
limitation persists, as all these methods use a fixed number
of Gaussians after training, making Level of Detail (LOD)
control challenging. Our work is the first to introduce con-
tinuous LOD control for 3DGS head avatars, allowing for
a dynamic balance between rendering efficiency and visual
quality to suit various practical needs.
UV-based FlashAvatar [43] is similar to our method. It
uses a multi-layer perceptron (MLP) decoder to generate
expression-conditioned 3D Gaussians by taking a position-
ally encoded UV mesh geometry map and expression co-
efficients from FLAME [21] as input. Despite its simple
yet effective solution, it does not support changing the UV
map resolution after training. This is because 3D Gaussians
hold complex information, including unique rotations and
sizes, which prevents them from being easily scaled like im-
ages. Our work addresses this by proposing a learnable and
scalable UV-based feature field that enables the decoder to
adapt to varying UV resolutions.
2.3. Level of Detail in 3D Gaussian Splatting
Recent research has extended level of detail concepts to
3DGS, but these methods are mainly for static scenes such
as urban environments [22, 42]. Some methods introduce
the hierarchical structures, enabling efficient rendering by
pruning distant or less important Gaussians [18, 28, 33].
Other methods, such as CityGaussian and FLoD, focus on
scalable multi-level representations to adapt to hardware
constraints [22, 30]. LOD-GS applies the filtering mech-
anism that is sensitive to sampling rate to improve visual
quality across different zoom levels [45]. Milef et al. pro-
pose a continuous LOD method that learns to rank splats
by importance to enable efficient distance-based render-
ing without inference-time overhead [26]. Although these
methods are effective for large static scenes, they are less
suitable for 3D head avatars, which are highly dynamic and
require controllability to support facial animation.
The most relevant method to ours is LoDAvatar, which
adapts mesh triangle-bound Gaussians for full-body avatars
using hierarchical embedding and selective detail enhance-
ment [4]. However, LoDAvatar only supports discrete LOD
control and relies on synthetic multi-view images for train-
ing, making it less suitable for personalized avatar creation
from monocular video. In contrast, our work supports con-
tinuous LOD control for 3D Gaussian head avatars, making
the change of LOD smooth while also allowing the training
from monocular videos for better photorealism.
3. Method
3.1. Preliminaries: 3D Gaussian Splatting
3D Gaussian Splatting (3DGS) represents a 3D scene us-
ing anisotropic 3D Gaussian primitives and renders them
through a splatting-based process that is both differentiable
and efficient [16]. The influence of a Gaussian at a 3D po-
sition x ∈R3 is defined by a modified Gaussian probability
density function:
G(x) = e−1
2 (x−µ)⊤Σ−1(x−µ),
(1)

<!-- page 4 -->
+
+
UV Map
Rasterizer
UV Position Map
Multi-Level 
UV Feature Field
Weighted
Resampler
FLAME
Decoder
UV Feature Map
Decoder
MLP
Mapping
MLP
3DGS
Camera Pose
Shape Code: 
Expression Code:  
Poses: 
+
Driving Code
Concatenation
LOD value: 
Resolution
Head Mesh
Learnable
Rendered
Image
Figure 2. Pipeline of ArchitectHead. We propose a 3D Gaussian head avatar creation method with continuous level of detail (LOD)
control. Starting from shape and expression codes, we use the FLAME head model to generate the 3D mesh geometry, which is rasterized
into a UV position map at the desired resolution. A multi-level UV feature field is introduced to learn local latent features, from which our
weighted resampler extracts a UV feature map of the target resolution. This map is concatenated with the UV position map, the desired
LOD value, and a driving code obtained from expression and pose codes via an MLP network M. The resulting pixel-wise latent features
are decoded by an MLP-based decoder into 3D Gaussian attributes, which are rendered using 3D Gaussian Splatting (3DGS).
where µ is the Gaussian center and Σ ∈R3×3 its covari-
ance. To guarantee Σ is positive semi-definite, it is con-
structed from a rotation matrix R and a scaling matrix S:
Σ = RSS⊤R⊤.
(2)
This corresponds to an oriented ellipsoid, parameterized
by a scale vector s and a quaternion q for 3D rotation
to avoid Gimbal lock. Each Gaussian is thus defined as
g = {µ ∈R3, s ∈R3, q ∈R4, α ∈R1, c ∈RSH}. α
is its opacity and c is the Spherical Harmonic (SH) coeffi-
cients for computing the color [6]. During rendering, the
Gaussians are projected to the 2D image plane and compos-
ited using alpha blending, similar to volume rendering [25].
3.2. Framework Overview
As shown in Figure 2, we leverage the geometry prior of
the FLAME head model [21] to initialize the positions of
3D Gaussians. The 3D head mesh m is derived as m =
F(βid, βexp, βjaw, βeye), where F is the FLAME decoder,
βid ∈R300, βexp ∈R100, βjaw ∈R3, and βeye ∈R6 are
the identity code, expression code, jaw pose, and eye poses,
respectively. Following [27], we add teeth to the original
FLAME mesh to better initialize Gaussians in the mouth
region. The mesh geometry is rasterized into a UV map.
We then apply positional encoding following [43] to obtain
Mpos ∈RS×S×DPE, where S is the desired UV resolution
and DPE is the dimensionality after positional encoding.
Denote the continuous LOD level as 0 ≤l ≤1.0, where
l = 0 corresponds to the highest LOD and l = 1.0 to the
lowest. Also, define Smax and Smin as the maximum and
minimum UV map resolutions, respectively. The desired
UV map resolution is then computed as:
S = Smax −l (Smax −Smin).
(3)
The UV feature map Mf ∈RS×S×Df , where Df is the
feature dimension, is resampled from the proposed multi-
level UV feature field (detailed in Section 3.3). This map
is then concatenated channel-wise with a positionally en-
coded UV position map, Mpos, to inject various frequency-
based information into the features. This approach, lever-
aging the learnable feature map Mf, significantly improves
the model’s ability to represent local details, which in turn
leads to enhanced visual quality.
Inspired by [20], we use a small multi-layer perceptron
(MLP) network M to learn the mapping from higher di-
mension codes (βexp, βjaw, and βeye) to a lower dimension
driving code with K dimensions. This code conditions the
decoder network on facial expressions. The mapping helps
the model focus on the most important expression variations
and reduces overfitting to specific expression or pose codes.
We then concatenate the driving code with the LOD value
l, creating a one-dimensional vector. This vector is then
appended to each pixel of the UV map, resulting in a final
feature map with DPE + Df + K + 1 channels.
The decoder network consists of five MLPs, each of
which is used for decoding the per-Gaussian UV feature
into one of the 3D Gaussian attributes: ∆µ, s, q, α, c. The
final Gaussian location is computed as µ = ∆µ + µinit,
where µinit is the initial position from the UV position map.
Given the camera pose, the decoded 3D Gaussians are ren-
dered through the 3DGS rasterizer to derive the image.
Please refer to the supplementary material for details.

<!-- page 5 -->
3.3. Multi-Level UV Feature Field
Existing works have shown that using higher-dimensional
learnable 3D Gaussian features can produce better visual
quality [9, 14, 31]. This is because higher-dimensional fea-
tures provide each 3D Gaussian point with greater repre-
sentational capacity.
Motivated by this, we propose us-
ing a 2D UV feature map to encode and learn these high-
dimensional, per-Gaussian features.
However, this ap-
proach presents a challenge when implementing continu-
ously controllable LOD if the UV feature map is simply
resized. Since each pixel in the map corresponds to a 3D
Gaussian point, neighboring Gaussians can have signifi-
cantly different rotations and scales. While downsampling
from a high to a low resolution can merge features of nearby
Gaussians, it also smooths out critical information, caus-
ing adjacent Gaussians to share overly similar attributes and
compromising local detail.
To address the above-mentioned issue, we propose to use
multiple UV feature maps of different resolutions to form
a multi-level feature field. We can resample a UV feature
map of any size between the largest and smallest UV fea-
ture maps in the multi-level feature field. Define the feature
field as a set of UV feature maps U = {MS1
f , ..., MSN
f } or-
dered by the resolutions S1, ..., SN increasingly. U contains
at least the feature maps of the maximum and minimum res-
olutions. To sample the feature map of a given resolution S
(Smin ≤S ≤Smax), we first resize all the feature maps
to the resolution of S using bi-cubic interpolation. Then we
blend all the resized feature maps via the following formula:
Mf =
N
X
i=1
wi ∗I(MSi
f , S),
(4)
where wi is the blending weight for the ith feature map
MSi
f , and I(MSi
f , S) is the bi-cubic interpolation function
that resizes MSi
f to a given resolution S.
The computation of wi is defined as follows:
wi =
exp(−|ri −r|/τ)
PN
j=1 exp(−|rj −r|/τ)
,
(5)
where ri = logeSi, r = logeS, τ > 0 is the tempera-
ture controlling the softness of interpolation. Equation 5 is
a softmax-based formulation, which gives higher weight to
the feature map whose resolution is closer to S, while en-
suring wi never reaches zero so that gradients can always
propagate properly.
3.4. Loss Functions
The training loss is defined as:
L = Lrgb + λlpipsLlpips + λµLµ + λs(1 −0.5l)Ls, (6)
where Lrgb is the image reconstruction loss, Llpips is the
LPIPS perceptual loss [43, 49], Lµ and Ls are regulariza-
tion terms on the Gaussian point location offsets and scales,
respectively, and λs are their weights. Both Lµ and Ls are
computed using the mean L2 norm of the location offsets
and scales. For Ls, we assign more weights to smaller l
(higher LOD) because the Gaussians are denser. Specifi-
cally, Lrgb has two sub-terms:
Lrgb = LH(I, ˆI) + λpartsLH(I · B, ˆI · B),
(7)
where LH is the Huber loss [15], I is the ground-truth im-
age, ˆI is the rendered image, and B is the binary mask of
eyes and mouth parts.
3.5. Training Scheme
The training has two stages. In the first stage, we use the
highest Level of Detail (LOD) to jointly optimize the multi-
level latent field along with the mapping network, M and
the decoder network D. The second stage of training fo-
cuses on the model’s ability to handle continuous detail.
In this stage, we randomly sample LODs from the range
[0, 1.0] and accumulate their loss gradients for optimization,
while keeping the mapping network M fixed.
4. Experiments
4.1. Datasets
We use two monocular video datasets in our experiments:
the PointAvatar dataset [51] and the INSTA dataset [52].
The PointAvatar dataset contains videos of three subjects,
while the INSTA dataset provides ten videos of different
subjects. Since one subject in INSTA overlaps with PointA-
vatar, we use only nine videos from INSTA. For each video,
the first 90% of frames are used for training and the remain-
ing 10% for evaluation.
4.2. Implementation Details
We implement our method using PyTorch. To render the 3D
Gaussians, we use the open-source 3DGS rasterizer gsplat
[46]. The maximum and minimum UV map resolutions are
set to Smax = 256 and Smax = 64, respectively. We use 12
frequencies for both sine and cosine in the positional encod-
ing, resulting in Dpos = 75 dimensions (see supplementary
materials). Following [20], we set the reduced driving code
dimension to K = 20. The learnable feature maps have
Df = 64 channels. The multi-level feature field consists of
three resolutions, 256 × 256, 128 × 128, and 64 × 64, re-
spectively. The temperature in Equation 5 is set to τ = 0.35.
We use SH = 3 in our work. We implement a fitting-based
FLAME head tracker to derive the FLAME codes and cam-
era pose for each frame in the monocular videos.
Training: Training is conducted on a single Nvidia RTX
4090 GPU with a batch size of one. In stage one, we train

<!-- page 6 -->
Ground Truth
GaussianAvatars
FlashAvatar
RGBAvatar
Gaussian Dejavu
Ours (LOD 0.0)
Ours (LOD 1.0)
Figure 3. Qualitative comparisons of self-reenactment results. Selected regions are zoomed in for clearer comparison of fine details.
The last two columns show our method with the highest (LOD=0.0) and lowest (LOD=1.0) settings. Compared to existing methods, our
approach preserves finer details at the highest LOD while also maintaining reasonable quality at the lowest LOD.
for 15,000 steps. In stage two, we render five LOD levels
at each step and train for 30,000 steps in total. The train-
ing time is approximately 30 minutes for stage one and 2.5
hours for stage two. Please refer to supplementary mate-
rials for details. The loss term weights are λparts = 20,
λlpips = 0.05, λµ = 0.001, and λs = 0.5.
4.3. Baselines
The baselines are state-of-the-art Gaussian head avatar
methods [20, 27, 43, 44]. Both GaussianAvatars [27] and
RGBAvatar [20] bind Gaussians to triangle facets, while
FlashAvatar [43] and Gaussian Dejavu [44] adopt UV-based
representations. In addition, both RGBAvatar and Gaussian
Dejavu employ Gaussian blendshapes to achieve expressive
animation. These methods are representative of the major
categories of Gaussian head avatars, including mesh-bound
[20, 27], UV-based [43, 44], and blendshape-based [20, 44].
4.4. Self and Cross-Identity Reenactment
Self-reenactment. The self-reenactment task involves us-
ing FLAME codes from a specific identity to drive an avatar
model that was trained on that same identity’s video. We
conduct experiments on both the PointAvatar and INSTA
datasets. The quantitative results in Tables 1 and 2 show
that the proposed method achieves the best performance
on both datasets across all metrics, including L1 distance,
PSNR, SSIM, and perceptual loss (LPIPS). We also evalu-
ated the trained avatar in half-precision (fp16), and the re-
sults are comparable to those obtained with full precision.
Figure 3 presents qualitative results. At the highest LOD
setting, our method captures finer details, while at the low-
est LOD setting it can still represent reasonable head shapes
with sparse Gaussian points. In addition, Figure 4 illustrates
novel views rendered from the reconstructed avatars.
Cross-Identity Reenactment.
In cross-identity reenact-
ment, we use FLAME codes from the video of one identity

<!-- page 7 -->
Method
L1 ↓
PSNR ↑SSIM ↑LPIPS ↓
GaussianAvatars [27]
0.048
26.009
0.916
0.112
FlashAvatar [43]
0.044
27.223
0.915
0.070
RGBAvatar [20]
0.053
28.106
0.907
0.100
Gaussian Dejavu [44]
0.045
27.819
0.923
0.065
Ours (fp16)
0.038
28.615
0.928
0.058
Ours (best)
0.038
28.621
0.928
0.058
Table 1. Quantitative comparisons of self-reenactment results
on PointAvatar dataset.
Method
L1 ↓
PSNR ↑SSIM ↑LPIPS ↓
GaussianAvatars [27]
0.030
26.979
0.945
0.069
FlashAvatar [43]
0.027
28.362
0.947
0.039
RGBAvatar [20]
0.037
27.583
0.924
0.060
Gaussian Dejavu [44]
0.024
29.722
0.956
0.034
Ours (fp16)
0.022
30.379
0.960
0.032
Ours (best)
0.022
30.389
0.960
0.032
Table 2. Quantitative comparisons of self-reenactment results
on INSTA dataset.
Yaw 
Yaw 
Pitch 
Pitch 
Reference
Figure 4. Rendered novel views. The reference images (left-
most) are rendered with the default camera pose, while the other
images are rendered with yaw or pitch angle offsets using an orbit
camera.
to drive avatars trained on another identity. Figure 5 shows
qualitative results. Our method achieves higher fidelity and
better visual quality compared to the baselines.
4.5. Level of Detail Control
In this experiment, we demonstrate the LOD control capa-
bility of the proposed method. Figure 6 shows the trained
avatar model rendered under different LOD settings. We ob-
serve that while the overall differences are subtle, the qual-
ity decreases in zoomed-in regions at lower LODs. There-
fore, for scenes where the camera is close to the avatar, we
recommend using a higher LOD to achieve better visual
quality. Conversely, if the camera is far away or quality is
less critical, a lower LOD can be used to save computational
resources. We also benchmark the rendering speed across
different LOD levels, with results summarized in Table 3.
Source
Gaussian
Avatars
Flash
Avatar
RGBAvatar
Gaussian
Dejavu
Ours
Figure 5. Qualitative results of cross-identity reenactment. The
first column shows the source images that provide the expression
codes and camera poses.
The remaining columns in each row
present the trained head avatar of another individual reenacted us-
ing the source codes and poses.
Using half-precision (fp16) leads to significantly faster ren-
dering at higher LODs. Importantly, the rendering qual-
ity does not degrade noticeably with fp16, even though the
model is trained in full precision (fp32); detailed compar-
isons are provided in the supplementary materials.
In Table 4, we evaluate different LOD settings.
At
the lowest LOD (l = 1.0), the model uses only 6.2% of
the Gaussians compared to the highest LOD, with a small
increase in L1 loss (+7.9%), and minor drops in PSNR
(–0.97%) and SSIM (–0.6%), while nearly doubling ren-
dering speed (+96% FPS).
LOD
#Gaussians
4090
(fp16)
4090
(fp32)
A6000
(fp16)
A6000
(fp32)
0.00
45,876
141
57
64
38
0.25
30,253
182
132
86
61
0.50
17,855
222
181
113
87
0.75
8,788
255
245
146
123
1.00
2,829
276
301
142
160
Table 3. Rendering FPS ↑(frames per second) performance com-
parison across LOD settings, GPUs, and floating-point precisions.
#Gaussians denotes the number of 3D Gaussian points.
4.6. Ablation Studies
We conduct ablation studies on the UV feature field. In the
first ablation, we completely remove the UV feature field,
meaning no learnable per-Gaussian features (w/o fmap). In

<!-- page 8 -->
LOD 0.0
LOD 0.25
LOD 0.5
LOD 0.75
LOD 1.0
Figure 6. Qualitative results of varying LODs. The second row
shows zoomed-in regions highlighted by the blue rectangle in the
first row. Red arrows indicate sub-optimal results (missing glare
and fine details), compared to the corresponding locations marked
by green arrows in our highest LOD (LOD=0) result. The third
row illustrates the same region (ear) rendered with different LODs
from 0.0 to 1.0 in steps of 0.05.
Method
LOD
L1 ↓
PSNR ↑
SSIM ↑
LPIPS ↓
0.0
0.038
28.621
0.928
0.058
Ours (full)
0.5
0.039
28.514
0.927
0.061
1.0
0.041
28.342
0.922
0.072
0.0
0.044
27.815
0.913
0.074
w/o fmap
0.5
0.044
27.864
0.914
0.074
1.0
0.048
27.436
0.907
0.087
0.0
0.041
28.295
0.913
0.063
fmap (64)
0.5
0.040
28.391
0.915
0.065
1.0
0.041
28.321
0.921
0.075
0.0
0.041
28.289
0.916
0.062
fmap (128)
0.5
0.041
28.423
0.917
0.065
1.0
0.042
28.191
0.912
0.074
0.0
0.039
28.614
0.926
0.059
fmap (256)
0.5
0.039
28.411
0.924
0.064
1.0
0.041
28.323
0.923
0.074
Table 4. Quantitative comparison across different ablation set-
tings and LODs. The bold results indicate the globally best score
across all methods and LODs. Within each LOD setting (0.0, 0.5,
1.0): we color the best and the second best results. w/o fmap de-
notes our method without the learnable UV feature map. fmap (.)
denotes our method where the multi-level UV feature field is re-
placed by a fixed-resolution learnable feature map, with the value
in parentheses indicating the resolution of the feature map.
the second ablation, we replace the multi-level feature field
with a single learnable feature map, and test three resolu-
tions: 64×64, 128×128, and 256×256. Self-reenactment
experiments are performed on the PointAvatar dataset, with
results summarized in Table 4. We observe that without
learnable features, the performance is the worst. When us-
ing a single-resolution feature map, higher resolution pro-
Ours (full)
w/o fmap
fmap (64)
fmap (128)
fmap (256)
Figure 7. Qualitative results of ablation study. w/o fmap de-
notes our method without the learnable UV feature map. fmap (.)
denotes our method where the multi-level UV feature field is re-
placed by a fixed-resolution learnable feature map, with the value
in parentheses indicating the resolution of the feature map. Red
arrows indicate artifacts, compared to the corresponding locations
marked by green arrows in our best (full method) result. We rec-
ommend zooming in to better inspect the details.
duces better quality. However, the proposed multi-level fea-
ture field (full) achieves the best results in most cases.
In Figure 7, we present the qualitative ablation results.
Notably, when comparing fmap (256) with our best result,
we observe more visual artifacts and blurrier sharp edges in
fmap (256). We attribute this to the fact that a single feature
map must represent all LOD levels, causing the lower LOD
representations to negatively affect the higher LOD results.
5. Limitations
Similar to most existing works, our method relies on accu-
rate FLAME tracking to provide reliable 3D-2D alignment,
which is essential for maintaining 3D consistency. In ad-
dition, we observe that some expression modes appear only
under large head poses in the video (e.g., side views). When
this happens, the network tends to overfit these rare cases,
leading to artifacts when such expression modes occur.
6. Conclusion
In this work, we propose ArchitectHead, a framework for
creating 3D Gaussian head avatars that supports real-time
and continuous adjustment of the level of detail (LOD).
To our knowledge, ArchitectHead is the first 3D Gaussian
head method to realize continuous LOD control. We pa-
rameterize Gaussians in UV feature space, which allows us
to control their number by simply adjusting the UV map
resolution. A neural decoder then generates the Gaussian
attributes, using the LOD as an additional condition. To
capture rich local information and balance different LODs
while ensuring smooth transitions between them, we intro-
duce a learnable UV latent feature map alongside the UV
position map to provide more representative information.
We then extend this design to a multi-level latent feature
field, which enables weighted resampling across resolutions
and improves the balance among varying LODs. Exper-

<!-- page 9 -->
iments on monocular video datasets show that Architect-
Head achieves state-of-the-art quality. For future work, we
plan to extend the framework to multi-view video datasets
and improve training efficiency.
References
[1] Volker Blanz and Thomas Vetter. A morphable model for the
synthesis of 3d faces. In Seminal Graphics Papers: Pushing
the Boundaries, Volume 2, pages 157–164. ACM New York,
NY, USA, 2023. 3
[2] Yufan Chen, Lizhen Wang, Qijing Li, Hongjiang Xiao,
Shengping Zhang, Hongxun Yao, and Yebin Liu. Monogaus-
sianavatar:
Monocular gaussian point-based head avatar.
arXiv preprint arXiv:2312.04558, 2023. 2, 3
[3] Helisa Dhamo, Yinyu Nie, Arthur Moreau, Jifei Song,
Richard Shaw, Yiren Zhou, and Eduardo P´erez-Pellitero.
Headgas: Real-time animatable head avatars via 3d gaus-
sian splatting. In European Conference on Computer Vision,
pages 459–476. Springer, 2024. 2, 3
[4] Xiaonuo Dongye, Hanzhi Guo, Le Luo, Haiyan Jiang, Yihua
Bao, Zeyu Tian, and Dongdong Weng. Lodavatar: Hierar-
chical embedding and adaptive levels of detail with gaus-
sian splatting for enhanced human avatars. arXiv preprint
arXiv:2410.20789, 2024. 2, 3
[5] Bernhard Egger, William AP Smith, Ayush Tewari, Stefanie
Wuhrer, Michael Zollhoefer, Thabo Beeler, Florian Bernard,
Timo Bolkart, Adam Kortylewski, Sami Romdhani, et al.
3d morphable face models—past, present, and future. ACM
Transactions on Graphics (ToG), 39(5):1–38, 2020. 3
[6] Sara Fridovich-Keil, Alex Yu, Matthew Tancik, Qinhong
Chen, Benjamin Recht, and Angjoo Kanazawa. Plenoxels:
Radiance fields without neural networks. In Proceedings of
the IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 5501–5510, 2022. 4
[7] Guy Gafni, Justus Thies, Michael Zollhofer, and Matthias
Nießner. Dynamic neural radiance fields for monocular 4d
facial avatar reconstruction. In Proceedings of the IEEE/CVF
Conference on Computer Vision and Pattern Recognition,
pages 8649–8658, 2021. 1
[8] Dimitrios
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
pages 10770–10782, 2025. 3
[9] Simon Giebenhain, Tobias Kirschstein, Martin R¨unz, Lour-
des Agapito, and Matthias Nießner. Npga: Neural paramet-
ric gaussian avatars. In SIGGRAPH Asia 2024 Conference
Papers, pages 1–11, 2024. 5
[10] Yisheng He, Xiaodong Gu, Xiaodan Ye, Chao Xu, Zhengyi
Zhao, Yuan Dong, Weihao Yuan, Zilong Dong, and Liefeng
Bo. Lam: Large avatar model for one-shot animatable gaus-
sian head. In Proceedings of the Special Interest Group on
Computer Graphics and Interactive Techniques Conference
Conference Papers, pages 1–13, 2025. 3
[11] Tan Kim Heok and Daut Daman. A review on level of de-
tail. In Proceedings. International Conference on Computer
Graphics, Imaging and Visualization, 2004. CGIV 2004.,
pages 70–75. IEEE, 2004. 2
[12] Hugues Hoppe. Progressive meshes. In Seminal Graphics
Papers: Pushing the Boundaries, Volume 2, pages 111–120.
2023. 2
[13] Liwen Hu, Shunsuke Saito, Lingyu Wei, Koki Nagano, Jae-
woo Seo, Jens Fursund, Iman Sadeghi, Carrie Sun, Yen-
Chun Chen, and Hao Li. Avatar digitization from a single
image for real-time rendering. ACM Transactions on Graph-
ics (ToG), 36(6):1–14, 2017. 3
[14] Ruigang Hu, Xuekuan Wang, Yichao Yan, and Cairong
Zhao.
Tgavatar: Reconstructing 3d gaussian avatars with
transformer-based tri-plane. IEEE Transactions on Circuits
and Systems for Video Technology, 2025. 5
[15] Peter J Huber. Robust estimation of a location parameter. In
Breakthroughs in statistics: Methodology and distribution,
pages 492–518. Springer, 1992. 5
[16] Bernhard Kerbl, Georgios Kopanas, Thomas Leimk¨uhler,
and George Drettakis.
3d gaussian splatting for real-time
radiance field rendering. ACM Transactions on Graphics, 42
(4):1–14, 2023. 1, 2, 3
[17] Tobias Kirschstein, Javier Romero, Artem Sevastopolsky,
Matthias Nießner, and Shunsuke Saito. Avat3r: Large an-
imatable gaussian reconstruction model for high-fidelity 3d
head avatars. arXiv preprint arXiv:2502.20220, 2025. 3
[18] Jonas Kulhanek, Marie-Julie Rakotosaona, Fabian Man-
hardt, Christina Tsalicoglou, Michael Niemeyer, Torsten Sat-
tler, Songyou Peng, and Federico Tombari. Lodge: Level-of-
detail large-scale gaussian splatting with efficient rendering.
arXiv preprint arXiv:2505.23158, 2025. 3
[19] Junxuan Li, Chen Cao, Gabriel Schwartz, Rawal Khirodkar,
Christian Richardt, Tomas Simon, Yaser Sheikh, and Shun-
suke Saito. Uravatar: Universal relightable gaussian codec
avatars. In SIGGRAPH Asia 2024 Conference Papers, pages
1–11, 2024. 2, 3
[20] Linzhou Li, Yumeng Li, Yanlin Weng, Youyi Zheng, and
Kun Zhou. Rgbavatar: Reduced gaussian blendshapes for
online modeling of head avatars.
In Proceedings of the
Computer Vision and Pattern Recognition Conference, pages
10747–10757, 2025. 2, 3, 4, 5, 6, 7
[21] Tianye Li, Timo Bolkart, Michael J Black, Hao Li, and Javier
Romero. Learning a model of facial shape and expression
from 4d scans. ACM Trans. Graph., 36(6):194–1, 2017. 3, 4
[22] Yang Liu, Chuanchen Luo, Lue Fan, Naiyan Wang, Jun-
ran Peng, and Zhaoxiang Zhang. Citygaussian: Real-time
high-quality large-scale scene rendering with gaussians. In
European Conference on Computer Vision, pages 265–282.
Springer, 2024. 3
[23] Shugao Ma, Tomas Simon, Jason Saragih, Dawei Wang,
Yuecheng Li, Fernando De La Torre, and Yaser Sheikh. Pixel
codec avatars. In Proceedings of the IEEE/CVF Conference
on Computer Vision and Pattern Recognition, pages 64–73,
2021. 3
[24] Shengjie Ma, Yanlin Weng, Tianjia Shao, and Kun Zhou. 3d
gaussian blendshapes for head avatar animation.
In ACM
SIGGRAPH 2024 Conference Papers, pages 1–10, 2024. 3
[25] Ben Mildenhall, Pratul P. Srinivasan, Matthew Tancik,
Jonathan T. Barron, Ravi Ramamoorthi, and Ren Ng. Nerf:

<!-- page 10 -->
Representing scenes as neural radiance fields for view syn-
thesis. In ECCV, 2020. 3, 4
[26] Nicholas Milef, Dario Seyb, Todd Keeler, Thu Nguyen-
Phuoc, A Boˇziˇc, Sushant Kondguli, and Carl Marshall.
Learning fast 3d gaussian splatting rendering using contin-
uous level of detail.
In Computer Graphics Forum, page
e70069. Wiley Online Library, 2025. 3
[27] Shenhan Qian, Tobias Kirschstein, Liam Schoneveld, Davide
Davoli, Simon Giebenhain, and Matthias Nießner.
Gaus-
sianavatars: Photorealistic head avatars with rigged 3d gaus-
sians. In Proceedings of the IEEE/CVF Conference on Com-
puter Vision and Pattern Recognition, pages 20299–20309,
2024. 2, 3, 4, 6, 7
[28] Kerui Ren, Lihan Jiang, Tao Lu, Mulin Yu, Linning Xu,
Zhangkai Ni, and Bo Dai. Octree-gs: Towards consistent
real-time rendering with lod-structured 3d gaussians. IEEE
Transactions on Pattern Analysis and Machine Intelligence,
2025. 3
[29] Markus Sch¨utz, Katharina Kr¨osl, and Michael Wimmer.
Real-time continuous level of detail rendering of point
clouds. In 2019 IEEE Conference on Virtual Reality and 3D
User Interfaces (VR), pages 103–110. IEEE, 2019. 2
[30] Yunji Seo,
Young Sun Choi,
Hyun Seung Son,
and
Youngjung Uh.
Flod: Integrating flexible level of detail
into 3d gaussian splatting for customizable rendering. arXiv
preprint arXiv:2408.12894, 2024. 2, 3
[31] Gent Serifi and Marcel C B¨uhler. Hypergaussians: High-
dimensional gaussian splatting for high-fidelity animatable
face avatars. arXiv preprint arXiv:2507.02803, 2025. 5
[32] Zhijing Shao, Zhaolong Wang, Zhuang Li, Duotun Wang,
Xiangru Lin, Yu Zhang, Mingming Fan, and Zeyu Wang.
Splattingavatar:
Realistic real-time human avatars with
mesh-embedded gaussian splatting. In Proceedings of the
IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 1606–1616, 2024. 2
[33] Jianxiong Shen, Yue Qian, and Xiaohang Zhan.
Lod-gs:
Achieving levels of detail using scalable gaussian soup. In
Proceedings of the Computer Vision and Pattern Recognition
Conference, pages 671–680, 2025. 3
[34] Luchuan Song, Yang Zhou, Zhan Xu, Yi Zhou, Deepali
Aneja, and Chenliang Xu.
Streamme: Simplify 3d gaus-
sian avatar within live stream. In Proceedings of the Special
Interest Group on Computer Graphics and Interactive Tech-
niques Conference Conference Papers, pages 1–10, 2025. 2,
3
[35] Jingxiang Sun, Xuan Wang, Lizhen Wang, Xiaoyu Li, Yong
Zhang, Hongwen Zhang, and Yebin Liu. Next3d: Gener-
ative neural texture rasterization for 3d-aware head avatars.
In Proceedings of the IEEE/CVF Conference on Computer
Vision and Pattern Recognition, pages 20991–21002, 2023.
3
[36] Towaki Takikawa, Joey Litalien, Kangxue Yin, Karsten
Kreis, Charles Loop, Derek Nowrouzezahrai, Alec Jacobson,
Morgan McGuire, and Sanja Fidler. Neural geometric level
of detail: Real-time rendering with implicit 3d shapes. In
Proceedings of the IEEE/CVF conference on computer vi-
sion and pattern recognition, pages 11358–11367, 2021. 2
[37] Jiapeng Tang, Davide Davoli, Tobias Kirschstein, Liam
Schoneveld, and Matthias Niessner. Gaf: Gaussian avatar
reconstruction from monocular videos via multi-view diffu-
sion.
In Proceedings of the Computer Vision and Pattern
Recognition Conference, pages 5546–5558, 2025. 2, 3
[38] Felix Taubner, Ruihang Zhang, Mathieu Tuli, and David B
Lindell. Cap4d: Creating animatable 4d portrait avatars with
morphable multi-view diffusion models. In 2025 IEEE/CVF
Conference on Computer Vision and Pattern Recognition
(CVPR), pages 5318–5330. IEEE Computer Society, 2025.
3
[39] Kartik Teotia,
Xingang Pan,
Hyeongwoo Kim,
Pablo
Garrido,
Mohamed Elgharib,
and Christian Theobalt.
Hq3davatar: High quality implicit 3d head avatar.
ACM
Transactions on Graphics, 2024. 3
[40] Huan Wang, Feitong Tan, Ziqian Bai, Yinda Zhang, Shichen
Liu, Qiangeng Xu, Menglei Chai, Anish Prabhu, Rohit
Pandey, Sean Fanello, et al.
Lightavatar: Efficient head
avatar as dynamic neural light field. In European Confer-
ence on Computer Vision, pages 183–201. Springer, 2024.
3
[41] Jie Wang, Jiu-Cheng Xie, Xianyan Li, Feng Xu, Chi-Man
Pun, and Hao Gao. Gaussianhead: High-fidelity head avatars
with learnable gaussian derivation. IEEE Transactions on
Visualization and Computer Graphics, 2025. 3
[42] Felix Windisch, Lukas Radl, Thomas K¨ohler, Michael
Steiner, Dieter Schmalstieg, and Markus Steinberger. A lod
of gaussians: Unified training and rendering for ultra-large
scale reconstruction with external memory. arXiv preprint
arXiv:2507.01110, 2025. 3
[43] Jun Xiang, Xuan Gao, Yudong Guo, and Juyong Zhang.
Flashavatar: High-fidelity digital avatar rendering at 300fps.
In Proceedings of the IEEE/CVF Conference on Computer
Vision and Pattern Recognition, 2024. 2, 3, 4, 5, 6, 7
[44] Peizhi Yan, Rabab Ward, Qiang Tang, and Shan Du. Gaus-
sian d´ej`a-vu: Creating controllable 3d gaussian head-avatars
with enhanced generalization and personalization abilities.
In 2025 IEEE/CVF Winter Conference on Applications of
Computer Vision (WACV), pages 276–286. IEEE, 2025. 2,
3, 6, 7
[45] Zhenya Yang, Bingchen Gong, and Kai Chen.
Lod-gs:
Level-of-detail-sensitive 3d gaussian splatting for detail con-
served anti-aliasing. arXiv preprint arXiv:2507.00554, 2025.
3
[46] Vickie Ye, Ruilong Li, Justin Kerr, Matias Turkulainen,
Brent Yi, Zhuoyang Pan, Otto Seiskari, Jianbo Ye, Jeffrey
Hu, Matthew Tancik, and Angjoo Kanazawa.
gsplat: An
open-source library for gaussian splatting. Journal of Ma-
chine Learning Research, 26(34):1–17, 2025. 5
[47] Dongbin Zhang, Yunfei Liu, Lijian Lin, Ye Zhu, Kangjie
Chen, Minghan Qin, Yu Li, and Haoqian Wang. Hravatar:
High-quality and relightable gaussian head avatar. In Pro-
ceedings of the Computer Vision and Pattern Recognition
Conference, pages 26285–26296, 2025. 2
[48] Jiawei Zhang, Zijian Wu, Zhiyang Liang, Yicheng Gong,
Dongfang Hu, Yao Yao, Xun Cao, and Hao Zhu. Fate: Full-
head gaussian avatar with textural editing from monocular

<!-- page 11 -->
video. In Proceedings of the Computer Vision and Pattern
Recognition Conference, pages 5535–5545, 2025. 2
[49] Richard Zhang, Phillip Isola, Alexei A Efros, Eli Shecht-
man, and Oliver Wang. The unreasonable effectiveness of
deep features as a perceptual metric. In Proceedings of the
IEEE conference on computer vision and pattern recogni-
tion, pages 586–595, 2018. 5
[50] Xiaozheng Zheng, Chao Wen, Zhaohu Li, Weiyi Zhang,
Zhuo Su, Xu Chang, Yang Zhao, Zheng Lv, Xiaoyuan
Zhang, Yongjie Zhang, et al. Headgap: Few-shot 3d head
avatar via generalizable gaussian priors.
In 2025 Inter-
national Conference on 3D Vision (3DV), pages 946–957.
IEEE, 2025. 2, 3
[51] Yufeng Zheng, Wang Yifan, Gordon Wetzstein, Michael J
Black, and Otmar Hilliges.
Pointavatar:
Deformable
point-based head avatars from videos.
In Proceedings of
the IEEE/CVF conference on computer vision and pattern
recognition, pages 21057–21067, 2023. 3, 5
[52] Wojciech Zielonka, Timo Bolkart, and Justus Thies. Instant
volumetric head avatars. In Proceedings of the IEEE/CVF
conference on computer vision and pattern recognition,
pages 4574–4584, 2023. 5
