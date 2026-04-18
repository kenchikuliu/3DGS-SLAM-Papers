<!-- page 1 -->
Using Gaussian Splats to Create High-Fidelity Facial Geometry and Texture
Haodi He
Epic Games, Stanford University
hardyhe@stanford.edu
Jihun Yu
Epic Games
jihun.yu@epicgames.com
Ronald Fedkiw
Epic Games, Stanford University
rfedkiw@stanford.edu
Abstract
We leverage increasingly popular three-dimensional neural
representations in order to construct a unified and consis-
tent explanation of a collection of uncalibrated images of
the human face. Our approach utilizes Gaussian Splatting,
since it is more explicit and thus more amenable to con-
straints than NeRFs. We leverage segmentation annotations
to align the semantic regions of the face, facilitating the
reconstruction of a neutral pose from only 11 images (as
opposed to requiring a long video). We soft constrain the
Gaussians to an underlying triangulated surface in order
to provide a more structured Gaussian Splat reconstruction,
which in turn informs subsequent perturbations to increase
the accuracy of the underlying triangulated surface. The
resulting triangulated surface can then be used in a standard
graphics pipeline. In addition, and perhaps most impact-
ful, we show how accurate geometry enables the Gaussian
Splats to be transformed into texture space where they can
be treated as a view-dependent neural texture. This allows
one to use high visual fidelity Gaussian Splatting on any
asset in a scene without the need to modify any other asset
or any other aspect (geometry, lighting, renderer, etc.) of the
graphics pipeline. We utilize a relightable Gaussian model
to disentangle texture from lighting in order to obtain a delit
high-resolution albedo texture that is also readily usable in
a standard graphics pipeline. The flexibility of our system
allows for training with disparate images, even with incom-
patible lighting, facilitating robust regularization. Finally,
we demonstrate the efficacy of our approach by illustrating
its use in a text-driven asset creation pipeline.
1. Introduction
Facial avatars are essential for a wide range of applications
including virtual reality, video conferencing, gaming, feature
films, etc. As virtual interactions become more prevalent,
the demand for compelling digital representations of human
faces will continue to grow. A person’s face avatar should
accurately reflect their identity, while also being controllable,
relightable, and efficient enough to use in real-time applica-
tions. These requirements have driven significant research
endeavors in computer vision, computer graphics, and ma-
chine learning. However, it is still challenging to create such
avatars in a scalable and democratized way, i.e. with com-
modity hardware and limited input data and without using
multiple calibrated cameras or a light-stage.
Neural Radiance Fields (NeRFs) [74] have become in-
creasingly prevalent in both computer vision and computer
graphics due to their impressive ability to reconstruct and
render 3D scenes from 2D image collections. In particular,
various authors have achieved impressive photorealistic re-
sults on 3D human faces. The implicit nature of the NeRF
representation facilitates high-quality editing (see e.g. [21]),
since it keeps edits both non-local and smooth (similar to
splines, but dissimilar to triangulated surfaces). In addition,
the regularization provided by the low dimensional latent
space keeps edits of faces looking like faces. It is far more
difficult for non-expert users to edit triangulated surface
geometry and textures directly.
Although only recently proposed, Gaussian Splatting [53]
has quickly become remarkably popular. Its explicit nature
makes it significantly more amenable to various constraints
than other (typically implicit) neural models. Importantly,
NeRFs and Gaussian Splatting complement each other, as
one can edit a NeRF representation before converting it into a
Gaussian Splatting model for various downstream tasks that
would benefit from having a more structured and constrained
representation.
The standard graphics pipeline has been refined over
decades via both software and hardware optimizations and
has become quite mature, especially for real-time applica-
tions. In fact, in spite of the maturity and impact of ray trac-
ing, it has only recently been somewhat incorporated into
gaming consoles and other real-time applications. Silicon
chip development is often a zero-sum game where adding
one capability necessarily removes another. However, ray
tracing has been embraced in non-realtime applications and
is often used to create content for real-time applications. It
is not a stretch to assume that neural rendering methods will
be treated similarly. Thus, converting neural models, such
as Gaussian Splatting, into triangulated surfaces with tex-
arXiv:2512.16397v1  [cs.CV]  18 Dec 2025

<!-- page 2 -->
Constrained 
Gaussian 
Model
Segmentation Maps
Gaussian 
Boundary Points
Fitted Triangulated 
Mesh
Figure 1. Using a small number of self-captured uncalibrated multi-view images, we use segmentation annotations along with size and shape
constraints to force the Gaussians to move instead of deform. In addition, soft constraints are used to keep the Gaussians tightly coupled and
close to the triangulated surface. After training, in a post process, the triangulated surface is deformed to better approximate the Gaussian
reconstruction.
tures disentangled from lighting necessarily increases their
immediate impact on real-time computer graphics applica-
tions. In this work, we address this by introducing a pipeline
that transforms a Gaussian Splatting model trained with self-
captured uncalibrated multi-view images into a triangulated
surface with de-lit textures.
Our method offers significant advantages over traditional
mesh-based geometry reconstruction, since it does not rely
on the ability of advanced shading models to overcome the
domain gap between synthetic and real images. Instead,
neural rendering is used to close the domain gap, while
constraints are used to tightly connect the neural rendering
degrees of freedom to an explicit triangulated surface. The
Gaussian Splatting model is modified to more tightly cou-
ple it to the triangulated surface in two ways: segmentation
annotations along with size and shape constraints are used
to force the Gaussians to move (instead of deform) in order
to explain the data, and soft constraints are used to keep
the Gaussians tightly coupled and close to the triangulated
surface. After training, in a post process, the triangulated
surface is deformed to better approximate the Gaussian re-
construction. See Fig. 1 and Fig. 2.
In order to obtain a de-lit texture with albedo disentangled
from normal and lighting, without the need of a light-stage,
we regularize this underconstrained problem by utilizing
a PCA representation of a mesh-based facial texture de-
rived from the Metahuman dataset [33]. We optimize the
PCA coefficients to reconstruct albedo as faithfully as pos-
sible, while minimizing reliance on a Relightable Gaussian
Splatting model that is used to capture residual differences
between a target image and a rendering of the textured mesh.
In summary, we obtain an accurate triangulated surface re-
construction with de-lit high-resolution textures, compatible
with a standard graphics pipeline. Moreover, we demon-
strate the efficacy of our approach by illustrating its use
in a text-driven asset creation pipeline. Key contributions
include:
• We propose two key modifications of Gaussian Splatting
in order to enable accurate triangulated surface reconstruc-
tion: Soft constraints encourage Gaussians to be more
tightly coupled to the underlying mesh, so that Gaussians
perturbations can more accurately drive mesh deformation.
Segmentation annotations supervise the Gaussians, so that
they do not attempt to explain regions of the target image
Reconstructed Image
Gaussians
Mesh
Our method
w/o Segmentation
w/o Constraints
Figure 2. The ground-truth is well-reconstructed (column 1) not
only by our method but also in the ablation tests where segmenta-
tion supervision (row 2) and constraints (row 3) have been omitted.
Omitting segmentation supervision allows the Gaussians to incor-
rectly explain regions of the image that their triangles should not
be associated with (compare row 2 column 2 to row 1 column 2),
resulting in spurious geometry (row 2 column 3). Omitting soft
constraints disconnects the Gaussians from their triangles resulting
in very spurious geometry (row 3 column 3).

<!-- page 3 -->
that they should not be associated with.
• We present a method that disentangles albedo textures
from lighting and normals. The PCA coefficients of the
textured mesh are optimized to capture as much albedo
color as possible while minimizing the contributions from
the relightable Gaussians that are used to capture differ-
ences between the synthetic rendering of the mesh and the
target image.
• Our method avoids the need of controlled capture setups
and instead requires only commodity hardware and limited
number of views. In fact, the flexibility of our approach
allows for joint training using data from different capture
setups; as an example, we combine images from our cap-
ture method with those obtained from so-called flashlight
capture (see e.g. [44]).
• Finally, and perhaps most importantly, we illustrate that
the geometry obtained via our pipeline is accurate enough
to use in conjunction with a view-dependent neural tex-
ture. In particular, we purpose a novel Gaussian Splatting
approach to view-dependent neural textures, emphasizing
that this enables the utilization of high visual fidelity Gaus-
sian Splatting on any asset in a scene without the need
to modify any other asset or any other aspect (geometry,
lighting, renderer, etc.) of the graphics pipeline.
2. Related Work
NeRFs:. Generally speaking, NeRFs disentangle camera
intrinsics and extrinsics from facial and other representations
by predicting color and density for volumetric ray march-
ing. Some frameworks utilize parameterized models such
as 3DMM (e.g. [34, 47, 127]), FLAME (e.g. [2, 30]), or
related parameterization (e.g. [36]) as inputs; then, expres-
sion parameters are used to morph a neutral expression-less
face from a canonical space into the scene (e.g. [95]). Al-
though NeRFs do not disentangle geometry, coarse geometry
is sometimes used to drive the morph (e.g. [5, 128]). Some
works (e.g. [88, 114]) have aimed to relight NeRFs, but the
coarse geometry and the entanglement between geometry
and texture hinders the ability to disentangle lighting in a
manner that facilitates the incorporation of NeRFs into a
standard graphics pipeline. Still, the implicit representation
and the latent space regularization make NeRFs a powerful
editing framework (e.g. [21, 51, 60, 92]). The latent space
regularization also makes NeRFs good candidates for democ-
ratized personal avatar generation using only a few images
or a quick phone scan (e.g. [11, 12, 14, 114]).
Gaussian Splatting:. Similar to NeRFs, Gaussian Splat-
ting methods use expression parameters to deform a canon-
ical space representation (e.g. [103, 110, 111, 121]), often
with the aid of a triangulated surface (e.g. [17, 81, 90, 94]).
In fact, triangulated surfaces can be used to parent Gaus-
sians for other structures as well, such as hair (e.g. [102]).
Gaussian Splatting has surpassed NeRFs in a number of ar-
eas, including for democratized personal avatar generation
(e.g. [19, 45, 65, 68, 89]). We utilize a relightable Gaussian
Splatting model (e.g. [61, 87]) in order to disentangle texture
from lighting. Most similar to our approach, [64] leverages
Gaussian Splatting to reconstruct a sequence of triangulated
surface meshes with high-resolution textures from multi-
view light stage videos; in contrast, our method does not
require a controlled capture setup and enables de-lighting of
the texture.
Other Neural Representations:. Besides NeRFs and Gaus-
sian Splatting, there are number of other neural approaches.
The vast majority of these are based on GANs [41], see
e.g. [66, 101]. Most of the three-dimensional approaches rely
on implicit formulations and SDFs (e.g. [40, 44, 115, 122]),
although some approaches do use explicit geometry (see
e.g. [123], which uses a point-based approach). Several
works (e.g. [42, 70, 91, 102]) employ meshes with view
and expression dependent neural textures, following [98], to
further enhance photorealism.
Geometry Reconstruction:. Mesh-based geometry recon-
struction typically relies on PCA for regularization to combat
noise. Popular examples include 3DMM [7], FLAME [63],
and other variants (e.g. [6, 10, 13, 79, 104]). Some methods
compute additional per-vertex deformations that are added
on top of the parameterized geometry. Older approaches use
various approximations to rendering (e.g. [37, 38]), while
newer approaches use either a fully differentiable ray tracer
(e.g. [29, 104]) or neural rendering (e.g. [42, 70, 98]). Ma-
chine learning approaches rely on the ability to pretrain a
model on large datasets (e.g. [3, 13, 20, 69, 83, 85, 86, 108,
116, 125]), inferring mesh parameters using either a single
view (e.g. [15, 56, 85, 96, 99, 100, 109, 113, 118]) or multi-
ple views (e.g. [9, 26, 97]).
Texture and Lighting:. Although chrome spheres have
been used to estimate on-set lighting conditions for feature
films for three decades (see e.g. [23]) and the main ideas
behind them originated even two decades before that (see
e.g. [8, 75]), much of the prior work still does not disentangle
texture from lighting. Of those that do aim to obtain de-lit
textures and lighting estimates, the higher-end efforts utilize
a light-stage (e.g. [24, 39, 71]), see for example [64, 87].
Using large-scale light-stage datasets (e.g. [57, 62]), neu-
ral networks can be trained to predict de-lit textures, sur-
face normals, and lighting conditions (e.g. [58, 76, 93]).
See also [54, 78, 107, 112].
In addition to approaches
that leverage a light-stage or light-stage data, a number
of approaches aim to disentangle texture from lighting for
in-the-wild single-view images under unconstrained condi-
tions: [28, 29, 100] incorporate physical or statistical regular-
izations, [48, 49] model shadows to better separate shading
from albedo, and [4, 124] generate pseudo ground-truth data

<!-- page 4 -->
to aid training. Similarly, various approaches utilize multi-
view images (e.g. [6, 61, 105, 123]).
3. Preliminaries
3.1. Gaussian Splatting
Gaussian Splatting [53] represents a scene using a collection
of 3D Gaussian primitives,
G(x) = e−1
2 (x−µ)⊤Σ−1(x−µ)
(1)
with mean position µ ∈R3 and covariance matrix Σ ∈
R3×3.
The covariance matrix is constructed via Σ =
RSS⊤R⊤with diagonal anisotropic scaling S and rotation
R. During rendering, each 3D Gaussian is projected to
a 2D Gaussian in screen space to obtain µ2D and Σ2D =
JWΣW ⊤J⊤where W is the viewing transformation and
J is the Jacobian of the projective transformation evaluated
at Wµ. Given an opacity α ∈[0, 1], the Gaussian makes a
contribution of
w(p) = αe−1
2 (p−µ2D)⊤Σ−1
2D (p−µ2D)
(2)
at pixel p. Pixel colors are computed using front-to-back
alpha compositing via
X
i

Y
j<i
(1 −wj(p))

wi(p)ci(v(µi))
(3)
where the viewing direction v is computed using the mean
position of the Gaussian, and the view-dependent color ci
is computed using v and the Gaussian’s learned per-channel
spherical harmonic coefficients.
3.2. Gaussian Avatars
Gaussian Avatars [81] represent deformable head models by
attaching Gaussians to the triangles of a mesh. The posi-
tion and covariance of each Gaussian is defined in the local
coordinate system of its parent triangle and driven by the
triangle’s motion via
µ(θ) = R(θ)µlocal + T(θ)
(4)
Σ(θ) = s(θ)2R(θ)ΣlocalR(θ)⊤
(5)
where R, T, and s are defined for each frame via construc-
tion. The translation T is set to be equal to the centroid of
the triangle. The first and second consistently chosen edges
are used to construct an orthogonal basis for the plane of the
triangle via Gram-Schmidt; then, columns of R are defined
using those two orthogonal vectors and their cross product.
The (scalar) scale factor s is defined by averaging the length
of a consistently chosen edge and its altitude. Ideally, R,
T, and s capture a significant portion of µlocal and Σlocal, al-
lowing the learned µlocal and Σlocal to focus on the fine-scale
geometric variations that are not captured by the triangle
mesh. Moreover, using the same canonical space version
of µlocal and Σlocal for every frame adds regularization to
combat overfitting.
Following [81], we regularize the local scaling (S in
Sec. 3.1, which is Slocal in Σlocal) via
Lscale =

X
i
max

ˆe⊤
i Slocalˆei, ϵscale

ˆei

2
(6)
aiming to shrink the diagonal entries of Slocal that are larger
than ϵscale = 0.6. Note, ˆei are the standard basis vector in
R3.
3.3. Relightable Gaussian Avatars
Relightable Gaussian Avatars [87] modify the color in Eq 3,
replacing it with the sum of a diffuse and a specular term.
For each of the three color channels, the diffuse component
is computed by integrating over the surface of a sphere
cdiffuse = ρ
Z
S
L(ω)d(ω) dω = ρ
X
k
Lkdk
(7)
where ρ is the learned albedo, L is the environment lighting,
and d is a learned radiance transfer function. The integral
in Eq. 7 is simplified into a summation by representing both
L and d via their spherical harmonics approximations. The
view-dependent specular term is defined by
cspecular(µi, ni, σi, evi)
= evi(v(µi))
Z
S
L(ω) G(ω, vr(v(µi), ni), σi) dω
(8)
where vr = 2(v · n) n −v is the mirror reflection direction
about a learned surface normal n, and the spherical Gaussian
kernel G depends on a learned specular sharpness σ. Note
that [87] combined a number of view-dependent terms and
aggressively dropped their dependence on ω so that they
could be pulled out of the integral and be represented by the
learnable ev.
4. Method
To summarize, our method reconstructs a (de-lit) textured tri-
angulated surface mesh, suitable for use in a standard graph-
ics pipeline, from either a short monocular video or a set of
images. In Section 4.1, we describe the data acquisition and
initialization steps, which include using landmark detection
in order to estimate head pose and to generate a coarse ap-
proximation to the triangulated surface. In Section 4.2, we
discuss how we use soft constraints and segmentation anno-
tations in order to more tightly couple the Gaussian Splatting
model to the underlying triangulated surface. In Section 4.3,
we discuss how our modified Gaussian Splatting model can

<!-- page 5 -->
Figure 3. The 11 predefined target head poses used for reconstruc-
tion.
be used to drive deformation of the underlying triangulated
surface in order to obtain detailed and representative recon-
structed geometry. In Section 4.4, we demonstrate that the
geometry obtained via our pipeline is accurate enough to use
in conjunction with a view-dependent neural texture. In Sec-
tion 4.5 and 4.6, we explain how we generate high-resolution
textures disentangled from lighting. Finally, in Section 4.7
we wrap up with the discussion on how to convert our final
result into a MetaHuman framework so that it can be used in
wide variety of applications.
4.1. Data Acquisition and Initialization
We capture a 4K-resolution monocular video of the subject
using the rear camera of an iPhone 14 held in a fixed position.
During recording, the subject slowly rotates their head while
maintaining a neutral expression. This is done outdoors
in shaded conditions in order to minimize harsh lighting
and specular highlights. Afterwards, each video frame is
center-cropped to a resolution of 2160 × 2160 pixels. A
pretrained landmark detection network [35] is used to infer
both facial and skull landmarks on each frame. Assuming
the camera is fixed (as it is in our data acquisition), the
skull landmarks are used to estimate the head pose (rotation
and translation) for each frame by comparing the inferred
landmarks with corresponding landmarks on a 3D canonical
template. Although this assumes that the subject and the
template have the same size head, we only require a rough
pose estimation during the initialization stage.
Eleven predefined target head poses are chosen for the
reconstruction, shown in Fig. 3. Given a predefined target
head pose, we select the closest non-blurry frame. Closeness
is measured by comparing the estimated rotation to the target
rotation, and blurriness is measured using the variance of
the Laplacian of the pixel values in the grayscale image
(as is typical, see e.g. [80]). Weights are used to combine
closeness and blurriness into an objective function, so that
the process can be automated via minimization.
Starting with a front-facing image, we obtain a rough
estimation to depth via [1]. Then, the image, depth estimate,
and landmarks are used as input into the MetaHuman An-
imator [35] in order to obtain a triangulated surface. The
resulting mesh is topologically consistent with other MetaHu-
mans making it compatible with modern graphics pipelines;
however, it does not well-represent the subject, given all the
rough approximation used in the process. On the other hand,
it does provide a good initial guess for Gaussian Splatting.
To simplify the model, we remove the triangles associated
with the teeth, inner mouth, and eyelashes resulting in a face
mesh with 47,944 triangles.
4.2. Modified Gaussian Splatting Model
Similar to Gaussian Avatars [81], we attach Gaussians to the
triangles of the mesh; however, we do not jointly optimize
the triangulated surface along with the Gaussian parameters
during training. This decoupling allows us to more readily
leverage various improvements in Gaussian Splatting as they
become available. It also allows us to independently use
mesh regularization and other mesh-based considerations
without adversely affecting the Gaussian Splatting. We as-
sign exactly one Gaussian to each mesh triangle and disable
both densification and pruning during training. This one-to-
one correspondence between Gaussians and mesh triangles
makes geometry regularization and subsequent surface re-
construction more straightforward.
It is worth noting two other approaches that modify the
Gaussian Splatting model in order to facilitate triangulated
surface reconstruction. [50] uses flattened two-dimensional
Gaussians along with depth distortion and normal consis-
tency regularization terms, and [43] uses SDF-based regular-
ization. These modifications all encourage the Gaussians to
better align with the surfaces they represent.
4.2.1. Soft Constraints for Geometric Regularization
We promote local geometric consistency of the Gaussians by
introducing soft regularization terms that encourage specific
geometric features to not vary too much across the mesh.
This is accomplished via
Lreg =
X
i

zi −
1
|E(i)|
X
j∈E(i)
zj

2
(9)
where E(i) represents Gaussians associated with mesh trian-
gles that share an edge with the triangle containing Gaussian
i. Note that i ̸∈E(i). Lreg encourages each zi to be equal
to the average z value of its neighbors. This incorrectly
weighted Laplacian smoothing (see [27]) is more similar to
a standard deviation with the global mean replaced by local
means.
To better regularize the eyeballs, which are disconnected
from the face mesh, we identify bi-directional nearest neigh-
bor pairs between triangle centroids of the eyeballs and tri-
angle centroids of the face mesh; then, Gaussians associated
with these nearest neighbor pairs are included in the con-
struction of E.
Center Displacements. Here, we consider the displacement
between each Gaussian center µi and its corresponding mesh

<!-- page 6 -->
triangle centroid Ti as the geometric feature of interest via
zi = µi −Ti in Eq. 9 in order to obtain Lcenter
reg
. This aims
to keep Gaussians as close to the mesh as their neighbors
are, helping to regularize subsequent mesh deformation that
will be driven in part by these offsets.
Local Normal.
Here, we consider the geometric feature zi = ni,local, the
local normal of Gaussian i, in Eq. 9 in order to obtain Lnormal
reg
.
This aims to keep disagreements in the normal direction be-
tween Gaussians and the mesh smoothly varying over the
mesh, again helping to regularize subsequent mesh deforma-
tion. Note that the method proposed in [81], discussed in
Section 3.2, for choosing R causes Σlocal and thus nlocal (the
third column of Σlocal) to vary inconsistently across the mesh.
This can be remedied by constructing R more consistently
from triangle to triangle, instead of using edge directions that
vary significantly across the mesh. In order to do this, we
use UV texture coordinates of the triangle vertices in order
to reconstruct fairly consistent U and V directions across the
mesh (see e.g. [59, Sec. 6.8]). Note that discontinuities in the
texture coordinates can be ignored by removing neighbors
from E. Since U and V are not necessarily orthogonal, we
retain U as our consistent direction and orthogonalize V to
be perpendicular to U.
Boundary Displacements.
Here, we consider zi =
x∗
i −Ti, which is the distance from the outer boundary
point x∗
i of the Gaussian to the triangle centroid Ti, in Eq.
9 in order to obtain Lboundary
reg
. This provides additional regu-
larization (in addition to µi −Ti) that constrains the shape
of the Gaussians and more directly affects silhouette bound-
aries. Whereas [64] extracts boundary points using only a
single Gaussian for each, we include the contribution from
neighboring Gaussians in order to more accurately reflect
the visible boundaries. In order to do this, we first define
N(i) as a set that contains the Gaussian i itself along with
its k-nearest neighbors in the UV texture space. Then, a ray
is defined via xi = µi + tni where µi is the center of the
Gaussian, ni is the normal of the triangle the Gaussian is
associated with, and t is the ray parameter. Next, for each
Gaussian j ∈N(i), we solve αjGj(xi) = τ in order to find
a boundary point of Gaussian j near Gaussian i based on the
density threshold τ. Note that we do not consider Gaussians
j ∈N(i) that do not have αjGj(µi) < τ, which indicates
that Gaussian j contains the center of Gaussian i based on
the density threshold τ. Finally, x∗
i is defined via t∗
i , where
t∗
i is the maximum of the tj found by solving αjGj(xi) = τ
for each j ∈N(i).
4.2.2. Semantic Segmentation for Supervision
We train a segmentation model using the architecture from
Mask2Former [18] with synthetic training data.
Since
MetaHuman textures are already semantically labeled, it
is straightforward to generate synthetic training data in tex-
ture space. Moreover, since the labels are consistent from
one MetaHuman to another, any manual adjustments to the
labels only need to be done once. Fig. 4 (left) shows the
labeled texture map with the neck, body, and hair all receiv-
ing the same (white) non-face label. The labeled images,
Fig. 4 (middle), have an additional (black) label indicating
the background region. In order to emphasize occlusion
boundaries, the (black) background label is expanded to por-
tions of the foreground to bound regions where the normals
are becoming perpendicular to the view directions. This
provides strong cues for the face silhouette.
Each Gaussian inherits a label from its associated triangle,
and the triangle labels are derived from a template texture,
Fig. 5 (left), that intentionally differs from Fig. 4 (left). Hair-
lines vary from person to person, and forcing triangles to
align with an incorrect hairline can lead to spurious defor-
mations of the forehead; thus, we expand the (red) face label
in the template texture so that it includes regions that may or
may not be covered with hair. It can be difficult to predict
the boundary between the face and the neck, especially due
to the non-linear deformations that occur in that region when
someone turns their head; thus, we expand the face label in
the template texture there as well. The remaining areas of
the texture are given (black) background labels, in contrast
to the (white) non-face foreground labels in Fig. 4 (left).
For each target image, the network from [73] is used to
segment the foreground from the background; then, our seg-
mentation network is used to predict foreground labels simi-
lar to Fig. 4 middle. Pixels with (white) non-face foreground
labels are ignored during training, allowing Gaussians with
any label to explain those regions of the image. In contrast,
the (black) background labels are retained to emphasize oc-
clusion boundaries. Let P be the set of pixels in the image
that are not ignored and L be the number of labels (including
Figure 4. The annotated texture map (left) used to create training
data: face (red), nose (blue), nostril (pink), top lip (green), bottom
lip (cyan), eyes (yellow), ears (dark red), non-face (white). The
labeled image (middle) has an additional (black) background label.
Note how the (black) background label has been expanded to por-
tions of the foreground in order to emphasize occlusion boundaries.
The segmentation network is trained to recover Fig. 4 (middle)
from Fig. 4 (right).

<!-- page 7 -->
Figure 5. The template texture (left) used to assign labels to Gaus-
sians: face (red), nose (blue), nostril (pink), top lip (green), bottom
lip (cyan), eyes (yellow), ears (dark red), background (black). Note
how the face label (red) has been expanded into both the hair and
neck regions, as compared to Fig. 4. Note the differences between
the labeled triangles (right) and what one would expect to obtain as
image labels from the segmentation network (Fig. 4 middle).
the background) being used. Then, the segmentation loss is
Lseg =
1
|P|
X
p∈P
 ˆS(p) −onehotL(S(p))

2
(10)
where S is the segmentation label of pixel p and onehotL
converts from the set of segmentation labels to the set of ba-
sis functions {e1, ..., eL}. ˆS is constructed using all visible
Gaussians that overlap a pixel by alpha blending the one-hot
encoding of their segmentation labels. Lseg coerces Gaus-
sians to explain the parts of the images that they belong to,
which in turn will help to improve the alignment between the
triangulated surface and the images (when the triangulated
surface is later deformed, see Sec. 4.3).
4.2.3. Other Modifications
For each target image, the mesh is rendered from the current
camera view in order to identify back-facing and occluded
triangles, and Gaussians associated with those triangles are
ignored with a certain probability. This makes Gaussians
associated with visible triangles primarily responsible for
explaining the target image. Note that the Gaussians associ-
ated with hidden triangles are not entirely discarded, since
they may actually correspond to a portion of the target image.
This allows them to drag their hidden triangles towards the
appropriate portion of the target image.
An additional soft constraint is introduced to keep the
eyeball and eye socket Gaussians from interfering with each
other. Let x∗
eyeball and x∗
socket be the outer boundary points of
the eyeball and eye socket Gaussians, respectively. For each
eye socket Gaussian, let
ˆx∗
eyeball,i = arg min
j
x∗
eyeball,j −x∗
socket,i

2
(11)
be the closest eyeball Gaussian, and let ni be the unit normal
that points from the center of the eyeball (computed as the
mean of all x∗
eyeball,j) to ˆx∗
eyeball,i. Then,
Leyes = 1
Ns
Ns
X
i=1
max
  ˆx∗
eyeball,i −x∗
socket,i

· ni, 0

2
(12)
penalizes interference between the eyeball and eye socket
Gaussians. Ns is the number of Gaussians representing the
eye socket. See Fig. 6.
Target Image
w/o Eyes Loss
w/ Eyes Loss
Figure 6. The results obtained without and with the eye regular-
ization loss (Leyes in Eq. 12), respectively. The top row shows all
the Gaussians, while the bottom row omits the (yellow) eyeball
Gaussians in order to more clearly illustrate the errors in the (red)
eye socket Gaussians. Although both variations match the target
image, the result obtained without Leyes achieves this by allowing
the eyeball Gaussians to occlude the eye socket Gaussians. The
resulting mesh would have an inaccurately small eye socket. This
is alleviated by Leyes.
4.3. Triangulated Surface Deformation
We use our modified Gaussian Splatting to jointly optimize
the camera extrinsics and Gaussian parameters, as is typical.
Afterwards, the camera extrinsics are held fixed during ge-
ometry refinement. Each iteration, the Gaussian parameters
are re-optimized in order to provide supervisory information
for subsequent deformation of the triangulated surface. The
supervisory information takes the form of outer boundary
points for each Gaussian, i.e. the x∗
i from Sec. 4.2.1, ex-
cept that the combined contribution (replacing the max in
Sec. 4.2.1 with a sum) of each Gaussian and its k-nearest
neighbors is used. That is, for each Gaussian i,
X
j∈N (i)
αj Gj
 µi + t∗
i ni) = τ
(13)
is solved to find a ray parameter t∗
i that defines the outer
boundary point x∗
i = µi + t∗
i ni.
The vertices v of the triangulated surface are perturbed
by minimizing
Lcentroid =
X
i
 vcentroid
i
−x∗
i

2
(14)

<!-- page 8 -->
where the triangle centroid vcentroid
i
is the average of the
triangle vertices. In addition to the data term in Eq. 14,
two regularization terms are also included in the minimiza-
tion. Lvertex
reg
aims to keep the perturbation of each vertex
equal to average perturbation of its edge-connected neigh-
bors, and Lnormal
reg
penalizes the difference between changes
in the normal direction. Additional regularization can be had
by optimizing over the coefficients of a PCA basis, instead
of optimizing over the individual vertex positions directly.
We perform two iterations of geometry refinement, using
a MetaHuman per-region PCA formulation [33] in the first
iteration and individual vertex positions in the second. As
mentioned above, the Gaussians parameters are re-optimized
(using the current best guess for the geometry) before each
of these iterations.
4.4. Neural Texture Approach
Although Gaussian Splatting approaches typically use a tri-
angulated surface that only roughly approximate the geom-
etry, we illustrate the benefits of having an accurately re-
constructed triangulated surface in the section. Importantly,
this accurately reconstructed triangulated surface is valuable
even when one prefers the look of Gaussian Splatting to
that which can be obtained via a standard graphics pipeline
utilizing textured triangles. This emphasizes the efficacy of
our contribution. Although neural approaches have become
quite popular in the literature, they have not been widely
adopted in industry. It took decades to develop the software
and hardware used in the modern graphics pipeline, and the
various development were shaped by the need to embrace
artist creativity and control in every aspect of the pipeline.
Thus, less invasive approaches are likely to facilitate quicker
industry adoption. In this vein, we propose moving the Gaus-
sian Splatting model out of world space and into texture
space. This retains all the conveniences and efficiencies
of the software and hardware graphics pipeline while still
using Gaussian Splatting on assets of interest via a view-
dependent neural texture. Of course, neural textures require
more accurate geometry, again emphasizing the efficacy of
our contribution.
It is straightforward to transform world space triangles
to texture space, since their vertices already have UV coor-
dinates. The resulting transforms can be used to move the
Gaussians into a 3D UVW texture space in the same manner
that the Gaussians are moved from canonical space to world
space (see Sec. 3.2). Note that W encodes the orthogonal
distance from each Gaussian to its parent triangle. A view-
dependent neural texture can then be computed by splatting
the Gaussians perpendicularly with an “orthographic camera”
while still defining their color as a function of the world
space camera view as usual. Since the Gaussians live in a
canonical space, it is straightforward to compute both their
world space and texture space locations. Although there are
an infinite number of ways to represent a view-dependent
neural texture, we argue that the Gaussians provide an ex-
ceptionally good basis, as evidenced by their efficacy in
providing world space structure to camera space images.
Rendering the triangulated surface with a simple ambient-
only shader allows for a straightforward comparison between
standard Gaussian Splatting (Fig. 7, first image) and our
newly proposed neural texture approach (Fig. 7, second im-
age). Notably, the neural texture computes the color at each
point on the triangulated surface by α-blending Gaussians
along the normal direction instead of the usual approach of
α-blending along the ray direction. See Fig. 8. In addition,
pixels that overlap Gaussians but do not overlap the triangu-
lated surface are not shaded at all. Both of these differences
emphasize the need for the accurate geometry provided by
our method.
Since the Gaussians are being used differently, it makes
sense to retrain them (using their current parameters as a
warm start). After fine-tuning, the model generates even
cleaner details (Fig. 7, third image) than the standard ap-
proach (Fig. 7, first image). For the sake of computation
efficiency, we also experimented with replacing the usual α-
blending with a direct summation (along the lines of [119]).
This allows for purely 2D Gaussians in UV space (Fig. 7,
fourth image).
Treating the Gaussians as a neural texture has other ad-
vantages as well. For example, a mipmap can be created
by reducing both the number of texels and the number of
Gaussians. Notably, it is quite straightforward to accomplish
this in texture space in contrast to the difficulties associated
with significantly reducing the number of Gaussians for level
of detail representations in world space.
Importantly, Gaussian Splatting does a good job dealing
with camera extrinsics, allowing for the creation of an ac-
curate triangulated surface geometry. However, after asset
creation, it seems that Gaussian Splatting can be replaced
with a simpler neural or even spherical harmonic texture
with no loss of efficacy.
4.5. Lighting Estimation
Spherical harmonics [82] is used to approximate the light-
ing conditions via P
k lkAk Yk(np), where np is a per-pixel
unit-length surface normal, Yk are diffuse spherical harmonic
basis functions, Ak are normalization constants, and the lk
are learned three-color-channel coefficients. In order to en-
courage uniform values across color channels to prevent
color overfitting, the zeroth order coefficients are regularized
via Llighting =
l0 −¯l0

2, where ¯l0 is the mean value across
the three color channels. Each np is computed by perturb-
ing the interpolated vertex averaged normal by a learned
per-pixel rotation Rp meant to mimic a normal map. Each
Gaussian is given an additional learnable parameter Ri, and
the Ri are alpha-blended (as usual) in order to determine per-

<!-- page 9 -->
World Space
Pre Fine-Tuning
Texture Space
Fine-Tuned
w/o Occlusions
Figure 7. A comparison of standard Gaussian Splatting (first image)
to a view-dependent neural texture (other three images) for a novel
view. The second image shows the results obtained by using parent
triangles to transform the Gaussians into UVW texture space, and
the third image shows the results obtained after fine-tuning those
transformed Gaussians using the original views (this novel view
is not used for the fine-tuning). The fourth image removes the
α-blending by replacing it with a direct summation, so that the
Gaussians can be defined in a 2D UV texture space instead of a
3D UVW texture space for the sake of efficiency (if desired). For
the sake of comparison, all the images still utilize world-space
Gaussians for the non-face (hair, neck, eyeballs, etc.) regions.
World Space
(From Left)
(From Right)
Texture Space
Figure 8. In the world space approach, color accumulation is per-
formed along the ray direction; thus, the mixing of Gaussians is
view-dependent. When viewed from the left, Gaussians to the
left of each point on the surface need to properly combine with
the Gaussians above those points. When viewed from the right,
Gaussians to the right of each point on the surface need to properly
combine with the Gaussians above those points. In contrast, the
texture space approach always accumulates in the same direction,
orthogonal to the texture, regardless of the view direction. This
helps to prevent the blurriness issue for novel views, where the
Gaussians are accumulated in ways that were unanticipated during
training. In addition, reducing the influence of neighboring Gaus-
sians increases the locality and compactness of the texture space
approach (as compared to the world space approach) creating a
smaller circle of confusion and thus intrinsically higher resolution.
pixel Rp. Regularization of the form Lrotation = ∥Rp −I∥2
F
is added to limit the magnitude of the rotation. This normal
map reduces color artifacts around fine-scale features such
as wrinkles.
To improve rendering quality near occlusion boundaries
and reduce baked-in shadows, we precompute a screen-space
occlusion map for each target image, similar to [46]. For
each pixel, the corresponding point xp on the triangulated
surface is identified; then, Monte Carlo integration over the
hemisphere centered about (xp, np) is used to compute a
w/o Occlusion map
w/ Occlusion map
Figure 9. De-lit images recovered without and with the occlusion
map, respectively. The occlusion map reduces baked-in ambient
shadows, particularly in recessed regions such as below the nose
and along the lip crease, improving the de-lit textures.
per-channel visibility fraction
fvisible(p; l) =
P
k lk
P
j V (xp, dj)Yk(dj)np · dj
P
k lk
P
j Yk(dj)np · dj
(15)
where the visibility in direction dj, i.e. V (xp, dj) ∈{0, 1},
is computed based on the mesh geometry. Since fvisible is
expensive to evaluate, it is only computed occasionally using
the current best guess for np and the lk. Denoting the lagged
lk as lvisible, the per-pixel per-channel lighting estimate is
given by
L(p; l, lvisible) = fvisible(p; lvisible)
X
k
lk AkYk(np)
(16)
where np depends on both the triangulated surface and the
learned normal map. See Fig. 9.
4.6. De-lit Texture Generation
Although our method is motivated by [87], their method re-
lies on a large light stage dataset and thus cannot be applied
directly to our limited number of images taken by a single
camera without known or constrained lighting. To address
this, we regularize the problem with a rendering of the re-
constructed triangulated surface using the low-dimensional
texture space available in the MetaHuman framework; in
particular, we use the first 20 (out of a total of 137) PCA
coefficients. This leads to a texture P
j cjT j where the T j
are three-channel PCA basis functions and the cj are learned
during training. Augmenting this regularized texture with
Gaussian Splatting allows the model to match the training
data. The goal is to limit the contribution of the Gaussians
to high-frequency texture details and lighting variations in
order to obtain a de-lit mesh-based texture. See Fig. 10 for
an overview of our approach.
For each pixel, the per-pixel lighting estimate (see
Sec. 4.5) is multiplied channel-by-channel by the triangu-
lated surface texture interpolated to that pixel. A per-pixel
compositing weight βp is used to combine the contribution
from the Gaussians with a 1 −βp contribution from the

<!-- page 10 -->
Estimated 
Shading
Textured 
Mesh
Relightable
 Gaussian
De-lit Render
Shaded Render
High-Resolution 
De-lit Image
Unwrapped
Texture
Inpainted 
Texture
Target Image
Training
Diffuse
Specular
Figure 10. Our method combines a textured mesh with a relightable Gaussian model and estimated spherical-harmonics lighting to reproduce
a target image. After training, we render the view-independent albedo component to obtain a de-lit image and reintroduce high-frequency
details extracted from the reference image. The resulting high-resolution de-lit images are then unwrapped and inpainted to form a complete
high-resolution de-lit texture.
triangulated surface. Each Gaussian is given an additional
learnable parameter βi, and the βi are alpha-blended (as
usual) in order to determine per-pixel βp. During training,
the βi are regularized toward zero via Lblending = ∥βp∥2 in
order to favor reliance on the mesh.
For the Gaussian model, we modify the method proposed
in Sec. 3.3 in a number of ways in order to provide regu-
larization aimed to compensate for our much more limited
access to data. The diffuse term in Eq. 7 is calculated by
alpha compositing the learned albedo ρ along the lines of
Eq. 3 before multiplying it by the per-pixel lighting estimate
(from Eq. 16). The specular term in Eq. 8 and simplifications
thereof seem intractable in the face of limited data; thus, we
replace Eq. 8 with an extra view-dependent color term c,
identical to that which was discussed in and after Eq. 3. That
is, motivated by [87], we augment [53] to include an extra
view-independent diffuse term evaluated with the aid of a
spherical harmonic lighting estimate. The intent is to have
this diffuse term explain as much of the lighting as possi-
ble, so that the original view-dependent color term can be
minimized via Lview = ∥c∥2.
After training, de-lit images can be obtained by ignoring
the view-dependent color term and by setting the per-pixel
lighting estimate equal to a value of one. Lost or damaged
high-frequency texture details can be restored by extracting
them from the target images (via a high-pass filter) and using
them to replace the equivalent high-frequency content in the
de-lit images. Note that the target images are warped to bet-
ter align with the triangulated surface geometry (see [126])
before the high-frequency content is extracted. The method
proposed in [67] is used to project the corrected de-lit image
data into texture space where it can be gathered to texels in
order to obtain a de-lit texture.
Although using [67] to project and gather a de-lit texture
results in a high-quality result for most of the face, there are
some problematic areas. The eyebrows and other hair regions
will have artifacts baked into the texture, the neck region
suffers from limited visibility, the hairline on the scalp will
be erratic, etc. We remedy these issues by creating a mask
in texture space that separates the high-quality results from
the regions that are typically problematic. The texture in the
high-quality region is projected into the MetaHuman texture
space to find PCA coefficients for a global texture that can be
used to inpaint the problematic regions; afterwards, blending
is used to soften the texture transition at region boundaries.
4.7. MetaHuman Generation
Although we started with an initial guess that was consis-
tent with the MetaHuman framework (see Section 4.1), the
geometry perturbations discussed in Section 4.3 lead to a
vertex layout (sometimes referred to as spans in the industry)
that is inconsistent with the underlying Metahuman basis.
Thus, we use the mesh-to-MetaHuman [32] tool to convert
our reconstructed geometry back into the MetaHuman basis.
Since this process perturbs vertex positions, the PCA basis
function used for the texture no longer correspond to the

<!-- page 11 -->
Target Image
MetaHuman
Figure 11. Target image (left) and the MetaHuman reconstructed
with our pipeline (right). Note that the hair style, eyebrow style,
and eyeballs are manually selected from the MetaHuman database.
same surface locations. We remedy this by repeating the
lighting estimate and texture solve (discussed in Section 4.5
and Section 4.6) on the new geometry. Obviously, it would
be more efficient if only one lighting and texture solve were
required; however, the mesh-to-Metahuman process requires
an input texture (and better textures give better results). Al-
though the teeth, inner mouth, and eyelashes are added back
to the geometry via the mesh-to-MetaHuman process, we ig-
nore them (as usual) during the lighting estimate and texture
solve. Alternatively, MetaHuman Creator [31] in Unreal En-
gine 5.6, can be used to better preserve the input geometry;
in addition, this alleviates the need to repeat the lighting and
texture solve. See Fig. 11
5. Implementation Details
Follow [120], we combine a standard per-pixel L1 loss with
a structural similarity loss (SSIM from [106]), i.e.
Limg = (1 −λ)L1 + λLD-SSIM
(17)
where LD-SSIM multiplies the structural similarity by nega-
tive one so that it is maximized, and λ = 0.2. This approach
is also followed by [53, 81]. Limg is used in every stage
of the Gaussian training. In both the camera and geometry
optimization passes, the regularization terms discussed in
Sec. 4.2.1 are included; in addition, λscale = 50 for Lscale
from Sec. 3.2. In the camera optimization pass, λcenter
reg
= 10,
λnormal
reg
= 10, and λboundary
reg
= 50. In the geometry opti-
mization pass, λcenter
reg
= 20, λnormal
reg
= 10, λboundary
reg
= 500.
In both passes, λseg = 50 for Lseg from Sec. 4.2.2, and
λeyes = 20 for Leyes from Sec. 4.2.3. During texture recon-
struction, the regularization terms from Sec. 4.5 and Sec. 4.6
use λlighting = 10−3, λrotation = 0.2, λblending = 0.1, and
λview = 10−3.
The model is trained for 5000 iterations with one Gaus-
sian per triangle in both the camera and geometry optimiza-
tion passes. Before texture reconstruction, the mesh is subdi-
vided (without perturbing vertex positions) and each Gaus-
sian is split into four Gaussians. The new Gaussians are
located at the centers of the sub-triangles and otherwise in-
herit the properties of their parent Gaussian, except for a
reduction in scale by a factor of two. An additional 1000
iterations are used to refine the densified model. During
texture reconstruction, opacity, position, rotation, and scale
are kept fixed, and the learnable parameters are initialized as
follows: albedo and the view-dependent spherical harmonic
coefficients are set randomly, compositing weights are set
to 0.05, and normal map rotations start at the identity. The
texture reconstruction model is trained for 2000 iterations.
We use a learning rate of 5 × 10−3 for all Gaussian pa-
rameters, except for scale and compositing weights which
use 1 × 10−3 and 2 × 10−2 respectively. Slowing the con-
vergence of scale allows the model to better benefit from the
segmentation supervision. In the camera optimization pass,
the learning rate for camera extrinsics is set to 1 × 10−2.
During texture reconstruction, the learning rate for the light-
ing estimates is set to 5 × 10−4 and the learning rate for the
mesh-based texture PCA coefficients is set to 1 × 10−2. We
followed the training protocol of [81] for all other implemen-
tation details not explicitly specified.
When perturbing the vertices of the triangulated surface
as discussed in Sec. 4.3, we optimize the parameters (either
PCA coefficients or vertex positions) for 2000 iterations
using Adam [55] with a learning rate of 5 × 10−3. Lcentroid
is combined with the regularization terms via λvertex
reg
= 2
and λnormal
reg
= 0.2. In the PCA optimization, we found it
useful to penalize coefficients that exceeded a value of 1 via
λPCA
reg
= 1.
5.1. Segmentation Model Training
The segmentation network, described in Sec. 4.2.2, was
trained on 1600 randomly sampled identities from the
MetaHuman Creator [31]. Five 720 × 720 resolution im-
ages were used for each identity, yielding 8000 total image
pairs (Fig. 4, middle and right). Random eye controls, includ-
ing blinking, were included in the otherwise neutral facial
expressions. Lighting conditions were randomly sampled
from the 11 available environment presets. The 25◦FoV
camera always pointed at the center of the head, and its
distance from the center of the head was varied randomly
from 45 to 80 cm. Measured from the horizontal ray through
the center of the head that extends through the front middle
of the face, the pitch and yaw were randomly sampled to
be between ±40◦and ±80◦, respectively. We trained the
model for 40,000 iterations with a batch size of 4, and all
other training details follow the default settings of [18, 22].
An additional 60 randomly sampled identities, yielding 300
total image pairs, were used for validation.
6. Experiments
For each in-the-wild reconstruction, we capture monocular
video data as discussed in Sec. 4.1; then, eleven predefined

<!-- page 12 -->
Target Image
Ours
NextFace
NHA
Figure 12. Geometry reconstruction results comparing our method to NextFace [28] and NHA [42]. Contour curves have been overlaid on
key facial features in order to facilitate comparisons. Comparing column 2 to columns 4 and 6 illustrates that our method reconstructs better
geometry. It is important to stress that the projection of colors (overfit to an image) onto geometry, as shown in columns 5 and 7, obfuscates
errors in geometry reconstruction.
Target Image
NHA (w/ Expr.)
NHA (Neutral)
Figure 13. Allowing NHA [42] to overfit expressions to the target images does give slightly better results than those that are obtained by
fixing the expression to be held in a neutral pose, as we did for Fig. 12 (compare the 2nd and 3rd images here to the top right of Fig. 12).
However, as is typical, this expression overfitting leads to a poor (unusable) neutral pose as shown in the last two images.
target head poses are chosen for the reconstruction.
We ran various ablation tests to evaluate the efficacy of
our contributions. Omitting our segmentation supervision
causes Gaussians to be assigned to incorrect semantic re-
gions, i.e., sliding from nearby regions (e.g. the lip region)
or originating from different layers when Gaussians overlap
(e.g. the eye region). Omitting our soft constraints discon-
nects the Gaussian explanation from their triangles causing
the Gaussians to become disorganized with large size and
shape variations. In both cases, the quality of the recon-
structed mesh is deteriorated. See Fig. 2. Ablation test for
the eye regularization loss and occlusion map are shown in
Fig. 6 and Fig. 9, respectively.
6.1. Comparison with Prior Work
Fig. 12 compares our method with NHA [42] and
NextFace [28]. For [28], we use the multi-image version
for their reconstruction. For [42], we set their expression
and jaw pose coefficients to neutral and set their camera
intrinsics to match ours; otherwise, their method overfits to
obtain an unusable neutral expression (see Fig. 13). Both
of these state-of-the-art approaches exhibit misalignment of
semantic facial regions and (especially [28]) fail to capture
the facial silhouette in side views. Lacking a strong semantic
correspondence between their reconstructed geometry and
the image data, many methods allow texture to slide on the
geometry as it overfits to the image. This obfuscates errors
in geometry reconstruction, not only from those who intend
to use the method, but also from the method itself. That is,
methods that allow for texture sliding hinder their own abil-
ity to improve the geometry, since the final result no longer
differs from the image data. Our semantic segmentation and
soft constraints have been devised specifically to address
this issue. Since [28] and [42] do not obtain high quality de-

<!-- page 13 -->
Target Image
Ours
CoRA
Figure 14. Comparison between our method and CoRA [44], using their proposed method for data capture. Contour curves have been
overlaid on key facial features in order to facilitate comparisons. Comparing column 2 to column 5 illustrates that our method reconstructs
better geometry. CoRA introduces artifacts around the nose and jaw regions. These artifacts are also evident in the de-lit texture (column 7).
Comparing column 4 to column 7 illustrates that CoRA has more baked-in lighting in their textures. This makes them incorrectly appear
more three-dimensional, rather than flat (a de-lit texture should appear flat, see Fig. 15). Columns 3 and 6 show the de-lit textures from
columns 4 and 7 combined with the estimated lighting, in order to compare with the target image.
De-lit
Lit
Figure 15. Left: Ambient-only lighting on both a MetaHuman and
a sphere. Right: Full lighting on both. Note how flat the de-lit
version appears to be, turning a three-dimensional sphere into a flat
two-dimensional circle.
lit textures, we instead compare our texture reconstruction
approach to other methods.
Fig. 14 compares our method with the approach proposed
in [44], which uses flashlight capture to obtain image data.
Following their instructions, we obtained similar data for
our subject. The results labeled “CoRA” in the figure use
their approach on this data, and the results labeled “Ours”
in the figure use our approach on a subset of the data (our
approach requires only 11 frames, see Fig. 3). The artifacts
around the lips, nose, and jaw in the CoRA result are pri-
marily due to an incorrect disentanglement of geometry and
texture that allows errors in albedo and surface normals to
offset each other; however, note that CoRA does achieve
much better disentanglement than [28] and [42]. In compari-
son to CoRA, our method recovers sharper boundaries for
facial features. This is especially important because their
results are not readily animatable (ours are), meaning that
further errors will result when converting their soft implicit
surface boundaries to an explicit mesh that can be rigged for
animation. Importantly, our method achieves similar de-lit
textures under various lighting conditions (see Fig. 16). This
consistency foreshadows how well our de-lit texture can be
re-lit under novel lighting conditions, as shown in Fig. 17.
6.2. Utilizing Disparate Captures
Our method is flexible enough to utilize images captured
with disparate setups and lighting conditions. For exam-
ple, we can combine images from our outdoor capture (see
Sec. 4.1) with images acquired using flashlight illumina-
tion (see e.g. [44]). Despite the differences, our approach is
able to successfully integrate both datasets in order to pro-
duce a consistent geometry. Leveraging heterogeneous in-
puts facilitates the removal of spurious geometric variations,
regularizing away slightly non-neutral facial expressions,
small eye-shape differences, imperfections in camera intrin-
sics/extrinsics, etc. This is readily accomplished by allowing
each Gaussian to maintain a separate view-dependent color
for each disparate batch of images, while sharing all other at-
tributes (opacity, position, scale, rotation, segmentation label,
etc.). Importantly, our segmentation supervision provides
reliable geometric cues, preventing the per-capture view-

<!-- page 14 -->
Target Image
Ours
(lit)
Ours
(de-lit)
Ours
(de-lit)
Ours
(lit)
Target Image
Figure 16. Note how similar our de-lit textures appear (compare columns 3 and 4), despite the disparate lighting in the two tests. Also note
how well our de-lit textures respond to the lighting (columns 2 and 5), allowing for good matching to the target images (columns 1 and 6).
Lighting
Reference
Ours
CoRA
Figure 17. Each row illustrates a novel lighting condition, depicted
by a chrome sphere (column 1) and the rendering of an artist-created
MetaHuman (column 2). Our reconstructed texture (column 3)
matches the reference quite well, especially when compared to
CoRA (column 4).
dependent color from overfitting. When one batch of images
is deemed more reliable, its influence can be increased by
sampling from it more often during training. In fact, only the
most reliable images should be used for the texture recon-
struction, as regularization aims to blur important features.
See Fig. 18.
6.3. Text-driven Asset Creation
We demonstrate the efficacy of our approach by integrating
it into a text-driven asset creation pipeline. First, we use
ChatGPT [77] to generate an image with a neutral expression.
Then, we use Veo 3 [25] to create a video from the image
using the instruction “The actor rotates their head around.”
This creates data similar to our capture setup. Afterwards,
our pipeline can be executed as usual. See Fig. 19.
Target Image
Ours
Joint
Figure 18. The middle image shows the result obtained using
(only) our data capture strategy, while the far right image shows the
result obtained when combining our data with the data obtained via
flashlight capture. The additional flashlight capture data improves
rigid alignment, particularly in side views, as can be seen from the
better aligned eye and lip contours.
Reference Image
Images
MetaHuman
Figure 19. The reference image (left) was generated via a ChatGPT
prompt, and it was subsequently used to create a video via Veo 3.
The top row shows selected images from the video, and the bottom
row shows the result of our pipeline.
6.4. Additional Results
We provide reconstruction results for the identity shown in
Fig. 12 from additional views in Fig. 21., and results for an
additional identity in Fig. 20.

<!-- page 15 -->
Target Image
Ours
Figure 20. Reconstruction results for an additional identity.
Target Image
Ours
Figure 21. Reconstruction results of the identity shown in Fig. 12
from additional views.
7. Limitations
In spite of the progress we have made addressing de-lighting,
it remains difficult to address without a light-stage or sim-
ilarly non-democratizable specialized equipment. Our de-
Original Image
SwitchLight
SwitchLight + Ours
Figure 22. Column 1 shows the results obtained using Switch-
Light [54] to preprocess the images before using [67] to project and
gather a texture. Note that the eyebrows, neck, hairline etc. have
been inpainted via the PCA-based projection approach discussed
at the end of Sec. 4.6. Column 2 shows the result obtained using
SwitchLight to preprocess the images before fitting them into our
pipeline. Although SwitchLight does a reasonable job, our method
further suppresses baked-in shadows and aligns the texture with the
MetaHuman color space (e.g. the SwitchLight result is too dark).
lighting approach sacrifices some fine-grained geometric
details, such as wrinkles. Although surface normal informa-
tion could help to address this, Gaussians are not yet able
to predict surface normals accurately enough to provide a
remedy.
The eyes and eyelids are the most difficult regions for
our method to properly capture. This is because the over-
lapping Gaussians used in these regions do not have precise
segmentation or strong silhouette guidance. While semantic
segmentation does provide some supervision, it operates at
a coarse granularity. Improvements could be achieved by
incorporating high-quality, fine-grained landmark prediction.
Our framework focuses primarily on the face and does
not extract or regularize geometry for the hair, neck, etc. See
e.g. [52, 102, 117] for various options/discussions. Gaus-
sians in these areas remain unstructured and are thus not
used to optimize the geometry of the triangulated surface.
This may make camera pose estimation less reliable and
sometimes cause the reconstructed geometry to deviate from
the true head shape.
8. Conclusion
Our method leverages the remarkable ability of Gaussian
Splatting to explain a set of disparate images in a cohesive
way with a disentangled view, essentially solving the cam-
era extrinsics problem for democratizable approaches. Our
modifications of Gaussian Splatting facilitate its use in geom-

<!-- page 16 -->
etry reconstruction. The semantic segmentation supervision
allows the Gaussians to create accurate correspondences
between the image and the triangulated surface. The soft
constraints provide regularization and structure to the corre-
spondence. Our geometry reconstructions compare favorably
to the state-of-the-art. For texture, leveraging a PCA-based
albedo prior and a Relightable Gaussian Splatting model al-
lowed us to disentangle illumination from reflectance. This
resulted in a cleaner, flatter, and more consistent de-lit texture
than that which could be obtained by other democratizable
methods not relying on controlled lighting or a light stage.
Together, these design choices yield an accurate, relightable,
and animatable reconstruction that generalizes well across
subjects and lighting conditions, while remaining fully com-
patible with standard graphics pipelines.
Our approach is flexible enough to be used on a wide
range of data sources and capture setups, readily accommo-
dates disparate data, and can leverage inputs from other ap-
proaches. Notably, our ability to utilize disparate image data
facilitates the hybridization of our approach with portrait-
editing approaches (see e.g. [16, 72, 84]). In particular, [54]
achieves impressive portrait de-lighting and can be used to
de-light images before they are used in our pipeline. See
Fig. 22.
Even in the case where Gaussian Splatting is preferred
over the geometry and texture of a standard graphics pipeline,
obtaining good geometry (as our method enables) is still
rather useful. For example, better geometry provides better
accuracy when driving Gaussian Splats during animation.
Accurate geometry also allows, as shown in Sec. 4.4, the
Gaussian Splats to be transformed into texture space where
they can be used as a view-dependent neural texture. This
allows any asset (or any subset of any asset) to be treated
with Gaussian Splats without the need to modify any other
assets or any other aspect of the graphics pipeline, facilitating
immediate use of Gaussian Splats in high-end applications.
9. Acknowledgement
Research supported in part by ONR N00014-24-1-2644,
ONR N00014-21-1-2771, and ONR N00014-19-1-2285.
We would like to acknowledge Epic Games for additional
support.
References
[1] Ashutosh Agarwal and Chetan Arora. Attention attention
everywhere: Monocular depth prediction with skip attention.
In Proceedings of the IEEE/CVF Winter Conference on Ap-
plications of Computer Vision (WACV), pages 5861–5870,
2023. 5
[2] ShahRukh Athar, Zhixin Shu, and Dimitris Samaras. Flame-
in-nerf: Neural control of radiance fields for free view face
animation. In 2023 IEEE 17th International Conference on
Automatic Face and Gesture Recognition (FG), pages 1–8.
IEEE, 2023. 3
[3] Andrew D Bagdanov, Alberto Del Bimbo, and Iacopo Masi.
The florence 2d/3d hybrid face dataset. In Proceedings of the
2011 joint ACM workshop on Human gesture and behavior
understanding, pages 79–80, 2011. 3
[4] Haoran Bai, Di Kang, Haoxian Zhang, Jinshan Pan, and Lin-
chao Bao. Ffhq-uv: Normalized facial uv-texture dataset for
3d face reconstruction. In Proceedings of the IEEE/CVF con-
ference on computer vision and pattern recognition, pages
362–371, 2023. 3
[5] Ziqian Bai, Feitong Tan, Zeng Huang, Kripasindhu Sarkar,
Danhang Tang, Di Qiu, Abhimitra Meka, Ruofei Du, Ming-
song Dou, Sergio Orts-Escolano, et al. Learning personal-
ized high quality volumetric head avatars from monocular
rgb videos. In Proceedings of the IEEE/CVF Conference
on Computer Vision and Pattern Recognition, pages 16890–
16900, 2023. 3
[6] Linchao Bao, Xiangkai Lin, Yajing Chen, Haoxian Zhang,
Sheng Wang, Xuefei Zhe, Di Kang, Haozhi Huang, Xinwei
Jiang, Jue Wang, et al. High-fidelity 3d digital human head
creation from rgb-d selfies. ACM Transactions on Graphics
(TOG), 41(1):1–21, 2021. 3, 4
[7] Volker Blanz and Thomas Vetter. A morphable model for the
synthesis of 3d faces. In Seminal Graphics Papers: Pushing
the Boundaries, Volume 2, pages 157–164. 2023. 3
[8] James F Blinn and Martin E Newell. Texture and reflection
in computer generated images. Communications of the ACM,
19(10):542–547, 1976. 3
[9] Timo Bolkart, Tianye Li, and Michael J Black. Instant
multi-view head capture through learnable registration. In
Proceedings of the IEEE/CVF Conference on Computer
Vision and Pattern Recognition, pages 768–779, 2023. 3
[10] James Booth, Anastasios Roussos, Stefanos Zafeiriou, Allan
Ponniah, and David Dunaway. A 3d morphable model learnt
from 10,000 faces. In Proceedings of the IEEE conference
on computer vision and pattern recognition, pages 5543–
5552, 2016. 3
[11] Marcel C Buehler, Gengyan Li, Erroll Wood, Leonhard
Helminger, Xu Chen, Tanmay Shah, Daoye Wang, Stephan
Garbin, Sergio Orts-Escolano, Otmar Hilliges, et al. Cafca:
High-quality novel view synthesis of expressive faces from
casual few-shot captures. In SIGGRAPH Asia 2024 Confer-
ence Papers, pages 1–12, 2024. 3
[12] Marcel C B¨uhler, Kripasindhu Sarkar, Tanmay Shah,
Gengyan Li, Daoye Wang, Leonhard Helminger, Sergio
Orts-Escolano, Dmitry Lagun, Otmar Hilliges, Thabo Beeler,
et al. Preface: A data-driven volumetric prior for few-shot
ultra high-resolution face synthesis. In Proceedings of the
IEEE/CVF International Conference on Computer Vision,
pages 3402–3413, 2023. 3
[13] Chen Cao, Yanlin Weng, Shun Zhou, Yiying Tong, and Kun
Zhou. Facewarehouse: A 3d facial expression database for
visual computing. IEEE Transactions on Visualization and
Computer Graphics, 20(3):413–425, 2013. 3
[14] Chen Cao, Tomas Simon, Jin Kyu Kim, Gabe Schwartz,
Michael Zollhoefer, Shun-Suke Saito, Stephen Lombardi,

<!-- page 17 -->
Shih-En Wei, Danielle Belko, Shoou-I Yu, et al. Authentic
volumetric avatars from a phone scan. ACM Transactions
on Graphics (TOG), 41(4):1–19, 2022. 3
[15] Zenghao Chai, Tianke Zhang, Tianyu He, Xu Tan, Tadas
Baltrusaitis, HsiangTao Wu, Runnan Li, Sheng Zhao, Chun
Yuan, and Jiang Bian. Hiface: High-fidelity 3d face re-
construction by learning static and dynamic details.
In
Proceedings of the IEEE/CVF International Conference on
Computer Vision, pages 9087–9098, 2023. 3
[16] Sumit Chaturvedi, Mengwei Ren, Yannick Hold-Geoffroy,
Jingyuan Liu, Julie Dorsey, and Zhixin Shu. Synthlight:
Portrait relighting with diffusion model by learning to re-
render synthetic faces. In Proceedings of the Computer
Vision and Pattern Recognition Conference, pages 369–379,
2025. 16
[17] Yufan Chen, Lizhen Wang, Qijing Li, Hongjiang Xiao,
Shengping Zhang, Hongxun Yao, and Yebin Liu. Mono-
gaussianavatar: Monocular gaussian point-based head avatar.
In ACM SIGGRAPH 2024 Conference Papers, pages 1–9,
2024. 3
[18] Bowen Cheng, Ishan Misra, Alexander G. Schwing, Alexan-
der Kirillov, and Rohit Girdhar. Masked-attention mask
transformer for universal image segmentation. 2022. 6, 11
[19] Xuangeng Chu and Tatsuya Harada.
Generalizable and
animatable gaussian head avatar. Advances in Neural Infor-
mation Processing Systems, 37:57642–57670, 2024. 3
[20] Joon Son Chung, Arsha Nagrani, and Andrew Zisserman.
Voxceleb2: Deep speaker recognition.
arXiv preprint
arXiv:1806.05622, 2018. 3
[21] Armand Comas-Massagu´e, Di Qiu, Menglei Chai, Marcel
B¨uhler, Amit Raj, Ruiqi Gao, Qiangeng Xu, Mark Matthews,
Paulo Gotardo, Sergio Orts-Escolano, et al. Magicmirror:
Fast and high-quality avatar generation with a constrained
search space. In European Conference on Computer Vision,
pages 178–196. Springer, 2024. 1, 3
[22] MMSegmentation
Contributors.
MMSegmentation:
Openmmlab semantic segmentation toolbox and bench-
mark.
https : / / github . com / open - mmlab /
mmsegmentation, 2020. 11
[23] Paul Debevec. Rendering synthetic objects into real scenes:
Bridging traditional and image-based graphics with global
illumination and high dynamic range photography. In Acm
siggraph 2008 classes, pages 1–10. 2008. 3
[24] Paul Debevec, Tim Hawkins, Chris Tchou, Haarm-Pieter
Duiker, Westley Sarokin, and Mark Sagar. Acquiring the
reflectance field of a human face. In Proceedings of the 27th
annual conference on Computer graphics and interactive
techniques, pages 145–156, 2000. 3
[25] Google DeepMind. Veo: Google’s next-generation gen-
erative video model. https://deepmind.google/
models/veo/, 2024. Accessed: 2025-03-29. 14
[26] Yu Deng, Jiaolong Yang, Sicheng Xu, Dong Chen, Yunde
Jia, and Xin Tong. Accurate 3d face reconstruction with
weakly-supervised learning: From single image to image set.
In Proceedings of the IEEE/CVF conference on computer
vision and pattern recognition workshops, pages 0–0, 2019.
3
[27] Mathieu Desbrun, Mark Meyer, Peter Schr¨oder, and Alan H
Barr. Implicit fairing of irregular meshes using diffusion and
curvature flow. In Proceedings of the 26th annual conference
on Computer graphics and interactive techniques, pages
317–324, 1999. 5
[28] Abdallah Dib, Gaurav Bharaj, Junghyun Ahn, C´edric
Th´ebault, Philippe Gosselin, Marco Romeo, and Louis
Chevallier. Practical face reconstruction via differentiable
ray tracing. In Computer Graphics Forum, pages 153–164.
Wiley Online Library, 2021. 3, 12, 13
[29] Abdallah Dib, Junghyun Ahn, Cedric Thebault, Philippe-
Henri Gosselin, and Louis Chevallier. S2f2: Self-supervised
high fidelity face reconstruction from monocular image. In
2023 IEEE 17th International Conference on Automatic
Face and Gesture Recognition (FG), pages 1–8. IEEE, 2023.
3
[30] Hao-Bin Duan, Miao Wang, Jin-Chuan Shi, Xu-Chuan Chen,
and Yan-Pei Cao. Bakedavatar: Baking neural fields for real-
time head avatar synthesis. ACM Transactions on Graphics
(ToG), 42(6):1–17, 2023. 3
[31] Epic Games.
Metahuman creator.
https : / /
dev.epicgames.com/documentation/en-us/
metahuman/metahuman-creator, 2025. Accessed:
2025-07-15. 11
[32] Epic Games. Mesh to metahuman, 2025. Accessed: 2025-
07-07. 10
[33] Epic
Games.
MetaHuman.
https : / / www .
unrealengine.com/en-US/metahuman, 2025. Ac-
cessed: 2025-05-13. 2, 8
[34] Guy Gafni, Justus Thies, Michael Zollhofer, and Matthias
Nießner. Dynamic neural radiance fields for monocular 4d
facial avatar reconstruction. In Proceedings of the IEEE/CVF
Conference on Computer Vision and Pattern Recognition,
pages 8649–8658, 2021. 3
[35] Epic Games. Metahuman animator, n.d. Accessed: Novem-
ber 11, 2025. 5
[36] Xuan Gao, Chenglai Zhong, Jun Xiang, Yang Hong, Yudong
Guo, and Juyong Zhang. Reconstructing personalized se-
mantic facial nerf models from monocular video. ACM
Transactions on Graphics (TOG), 41(6):1–12, 2022. 3
[37] Pablo Garrido, Levi Valgaerts, Chenglei Wu, and Christian
Theobalt. Reconstructing detailed dynamic face geometry
from monocular video. ACM Trans. Graph., 32(6):158–1,
2013. 3
[38] Pablo Garrido, Michael Zollh¨ofer, Dan Casas, Levi Val-
gaerts, Kiran Varanasi, Patrick P´erez, and Christian Theobalt.
Reconstruction of personalized 3d face rigs from monocular
video. ACM Transactions on Graphics (TOG), 35(3):1–15,
2016. 3
[39] Abhijeet Ghosh, Graham Fyffe, Borom Tunwattanapong,
Jay Busch, Xueming Yu, and Paul Debevec. Multiview face
capture using polarized spherical gradient illumination. In
Proceedings of the 2011 SIGGRAPH Asia Conference, pages
1–10, 2011. 3
[40] Simon Giebenhain, Tobias Kirschstein, Markos Georgopou-
los, Martin R¨unz, Lourdes Agapito, and Matthias Nießner.
Mononphm: Dynamic head reconstruction from monocu-
lar videos. In Proceedings of the IEEE/CVF Conference

<!-- page 18 -->
on Computer Vision and Pattern Recognition, pages 10747–
10758, 2024. 3
[41] Ian Goodfellow, Jean Pouget-Abadie, Mehdi Mirza, Bing
Xu, David Warde-Farley, Sherjil Ozair, Aaron Courville, and
Yoshua Bengio. Generative adversarial networks. Commu-
nications of the ACM, 63(11):139–144, 2020. 3
[42] Philip-William Grassal, Malte Prinzler, Titus Leistner,
Carsten Rother, Matthias Nießner, and Justus Thies. Neural
head avatars from monocular rgb videos. In Proceedings of
the IEEE/CVF conference on computer vision and pattern
recognition, pages 18653–18664, 2022. 3, 12, 13
[43] Antoine Gu´edon and Vincent Lepetit.
Sugar: Surface-
aligned gaussian splatting for efficient 3d mesh reconstruc-
tion and high-quality mesh rendering. In Proceedings of
the IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 5354–5363, 2024. 5
[44] Yuxuan Han, Junfeng Lyu, and Feng Xu. High-quality facial
geometry and appearance capture at home. In Proceedings of
the IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 697–707, 2024. 3, 13
[45] Yisheng He, Xiaodong Gu, Xiaodan Ye, Chao Xu, Zhengyi
Zhao, Yuan Dong, Weihao Yuan, Zilong Dong, and Liefeng
Bo. Lam: Large avatar model for one-shot animatable gaus-
sian head. In Proceedings of the Special Interest Group on
Computer Graphics and Interactive Techniques Conference
Conference Papers, pages 1–13, 2025. 3
[46] Sebastian Herholz, Timo Schairer, and Wolfgang Straßer.
Screen space spherical harmonics occlusion (s3ho) sampling.
In ACM SIGGRAPH 2011 Posters, pages 1–1. 2011. 9
[47] Yang Hong, Bo Peng, Haiyao Xiao, Ligang Liu, and Juyong
Zhang. Headnerf: A real-time nerf-based parametric head
model. In Proceedings of the IEEE/CVF Conference on
Computer Vision and Pattern Recognition, pages 20374–
20384, 2022. 3
[48] Andrew Hou, Ze Zhang, Michel Sarkis, Ning Bi, Yiying
Tong, and Xiaoming Liu. Towards high fidelity face relight-
ing with realistic shadows. In Proceedings of the IEEE/CVF
conference on computer vision and pattern recognition,
pages 14719–14728, 2021. 3
[49] Andrew Hou, Michel Sarkis, Ning Bi, Yiying Tong, and
Xiaoming Liu. Face relighting with geometrically consistent
shadows. In Proceedings of the IEEE/CVF conference on
computer vision and pattern recognition, pages 4217–4226,
2022. 3
[50] Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger,
and Shenghua Gao. 2d gaussian splatting for geometrically
accurate radiance fields. In SIGGRAPH 2024 Conference
Papers. Association for Computing Machinery, 2024. 5
[51] Kaiwen Jiang, Shu-Yu Chen, Feng-Lin Liu, Hongbo Fu,
and Lin Gao. Nerffaceediting: Disentangled face editing in
neural radiance fields. In SIGGRAPH Asia 2022 Conference
Papers, pages 1–9, 2022. 3
[52] Hendrik Junkawitsch, Guoxing Sun, Heming Zhu, Chris-
tian Theobalt, and Marc Habermann. Eva: Expressive vir-
tual avatars from multi-view videos. In Proceedings of the
Special Interest Group on Computer Graphics and Interac-
tive Techniques Conference Conference Papers, pages 1–11,
2025. 15
[53] Bernhard Kerbl, Georgios Kopanas, Thomas Leimk¨uhler,
and George Drettakis. 3d gaussian splatting for real-time
radiance field rendering. ACM Trans. Graph., 42(4):139–1,
2023. 1, 4, 10, 11
[54] Hoon Kim, Minje Jang, Wonjun Yoon, Jisoo Lee, Donghyun
Na, and Sanghyun Woo. Switchlight: Co-design of physics-
driven architecture and pre-training framework for human
portrait relighting. In Proceedings of the IEEE/CVF Con-
ference on Computer Vision and Pattern Recognition, pages
25096–25106, 2024. 3, 15, 16
[55] Diederik P Kingma and Jimmy Ba. Adam: A method for
stochastic optimization. arXiv preprint arXiv:1412.6980,
2014. 11
[56] Tatsuro Koizumi and William AP Smith. “look ma, no
landmarks!”–unsupervised, model-based dense face align-
ment. In European Conference on Computer Vision, pages
690–706. Springer, 2020. 3
[57] Alexandros Lattas, Stylianos Moschoglou, Baris Gecer,
Stylianos Ploumpis, Vasileios Triantafyllou, Abhijeet Ghosh,
and Stefanos Zafeiriou. Avatarme: Realistically renderable
3d facial reconstruction” in-the-wild”. In Proceedings of
the IEEE/CVF conference on computer vision and pattern
recognition, pages 760–769, 2020. 3
[58] Alexandros Lattas,
Stylianos Moschoglou,
Stylianos
Ploumpis, Baris Gecer, Abhijeet Ghosh, and Stefanos
Zafeiriou. Avatarme++: Facial shape and brdf inference
with photorealistic rendering-aware gans. IEEE Transac-
tions on Pattern Analysis and Machine Intelligence, 44(12):
9269–9284, 2021. 3
[59] Eric Lengyel. Mathematics for 3D Game Programming and
Computer Graphics. Cengage Learning PTR, Florence, KY,
2 edition, 2003. 6
[60] Jianhui Li, Shilong Liu, Zidong Liu, Yikai Wang, Kaiwen
Zheng, Jinghui Xu, Jianmin Li, and Jun Zhu.
Instruct-
pix2nerf: instructed 3d portrait editing from a single image.
arXiv preprint arXiv:2311.02826, 2023. 3
[61] Junxuan Li, Chen Cao, Gabriel Schwartz, Rawal Khirodkar,
Christian Richardt, Tomas Simon, Yaser Sheikh, and Shun-
suke Saito. Uravatar: Universal relightable gaussian codec
avatars. In SIGGRAPH Asia 2024 Conference Papers, pages
1–11, 2024. 3, 4
[62] Ruilong Li, Karl Bladin, Yajie Zhao, Chinmay Chinara,
Owen Ingraham, Pengda Xiang, Xinglei Ren, Pratusha
Prasad, Bipin Kishore, Jun Xing, et al. Learning forma-
tion of physically-based face attributes. In Proceedings of
the IEEE/CVF conference on computer vision and pattern
recognition, pages 3410–3419, 2020. 3
[63] Tianye Li, Timo Bolkart, Michael J Black, Hao Li, and Javier
Romero. Learning a model of facial shape and expression
from 4d scans. ACM Trans. Graph., 36(6):194–1, 2017. 3
[64] Xuanchen Li, Yuhao Cheng, Xingyu Ren, Haozhe Jia, Di
Xu, Wenhan Zhu, and Yichao Yan. Topo4d: Topology-
preserving gaussian splatting for high-fidelity 4d head cap-
ture. In European Conference on Computer Vision, pages
128–145. Springer, 2024. 3, 6
[65] Tingting Liao, Yujian Zheng, Yuliang Xiu, Adilbek Kar-
manov, Liwen Hu, Leyang Jin, and Hao Li. Soap: Style-
omniscient animatable portraits.
In Proceedings of the

<!-- page 19 -->
Special Interest Group on Computer Graphics and Inter-
active Techniques Conference Conference Papers, pages
1–11, 2025. 3
[66] Connor Z Lin, David B Lindell, Eric R Chan, and Gordon
Wetzstein. 3d gan inversion for controllable portrait image
animation. arXiv preprint arXiv:2203.13441, 2022. 3
[67] Winnie Lin, Yilin Zhu, Demi Guo, and Ron Fedkiw. Lever-
aging deepfakes to close the domain gap between real and
synthetic images in facial capture pipelines. arXiv preprint
arXiv:2204.10746, 2022. 10, 15
[68] Xiangyue Liu, Kunming Luo, Heng Li, Qi Zhang, Yuan Liu,
Li Yi, and Ping Tan. Gaussianavatar-editor: Photorealistic
animatable gaussian head avatar editor, 2025. 3
[69] Ziwei Liu, Ping Luo, Xiaogang Wang, and Xiaoou Tang.
Deep learning face attributes in the wild. In Proceedings
of the IEEE international conference on computer vision,
pages 3730–3738, 2015. 3
[70] Shugao Ma, Tomas Simon, Jason Saragih, Dawei Wang,
Yuecheng Li, Fernando De La Torre, and Yaser Sheikh. Pixel
codec avatars. In Proceedings of the IEEE/CVF Conference
on Computer Vision and Pattern Recognition, pages 64–73,
2021. 3
[71] Wan-Chun Ma, Tim Hawkins, Pieter Peers, Charles-Felix
Chabert, Malte Weiss, Paul E Debevec, et al. Rapid acqui-
sition of specular and diffuse normal maps from polarized
spherical gradient illumination. Rendering Techniques, 9
(10):2, 2007. 3
[72] Debin Meng, Christos Tzelepis, Ioannis Patras, and Georgios
Tzimiropoulos. Mm2latent: Text-to-facial image generation
and editing in gans with multimodal assistance. In European
Conference on Computer Vision, pages 88–106. Springer,
2024. 16
[73] Maxwell Meyer and Jack Spruyt. Ben: Using confidence-
guided matting for dichotomous image segmentation. arXiv
preprint arXiv:2501.06230, 2025. 6
[74] Ben Mildenhall, Pratul P Srinivasan, Matthew Tancik,
Jonathan T Barron, Ravi Ramamoorthi, and Ren Ng. Nerf:
Representing scenes as neural radiance fields for view syn-
thesis. Communications of the ACM, 65(1):99–106, 2021.
1
[75] Gene S Miller and CR Hoffman. Illumination and reflection
maps. In ACM SIGGRAPH, 1984. 3
[76] Thomas Nestmeyer, Jean-Franc¸ois Lalonde, Iain Matthews,
and Andreas Lehrmann.
Learning physics-guided face
relighting under directional light. In Proceedings of the
IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 5124–5133, 2020. 3
[77] OpenAI. Chatgpt (sept 12 version). https://chat.
openai.com/, 2025. Large language model. 14
[78] Rohit Pandey, Sergio Orts-Escolano, Chloe Legendre, Chris-
tian Haene, Sofien Bouaziz, Christoph Rhemann, Paul E
Debevec, and Sean Ryan Fanello. Total relighting: learning
to relight portraits for background replacement. ACM Trans.
Graph., 40(4):43–1, 2021. 3
[79] Pascal Paysan, Reinhard Knothe, Brian Amberg, Sami
Romdhani, and Thomas Vetter. A 3d face model for pose
and illumination invariant face recognition. In 2009 sixth
IEEE international conference on advanced video and signal
based surveillance, pages 296–301. Ieee, 2009. 3
[80] Jos´e Luis Pech-Pacheco, Gabriel Crist´obal, Jes´us Chamorro-
Martinez, and Joaqu´ın Fern´andez-Valdivia. Diatom auto-
focusing in brightfield microscopy: a comparative study.
In Proceedings 15th International Conference on Pattern
Recognition. ICPR-2000, pages 314–317. IEEE, 2000. 5
[81] Shenhan Qian, Tobias Kirschstein, Liam Schoneveld, Da-
vide Davoli, Simon Giebenhain, and Matthias Nießner. Gaus-
sianavatars: Photorealistic head avatars with rigged 3d gaus-
sians. In Proceedings of the IEEE/CVF Conference on Com-
puter Vision and Pattern Recognition, pages 20299–20309,
2024. 3, 4, 5, 6, 11
[82] Ravi Ramamoorthi and Pat Hanrahan. An efficient repre-
sentation for irradiance environment maps. In Proceedings
of the 28th annual conference on Computer graphics and
interactive techniques, pages 497–500, 2001. 8
[83] Chirag Raman, Charlie Hewitt, Erroll Wood, and Tadas
Baltruˇsaitis. Mesh-tension driven expression-based wrinkles
for synthetic faces. In Proceedings of the IEEE/CVF Winter
Conference on Applications of Computer Vision, pages 3515–
3525, 2023. 3
[84] Pramod Rao, Gereon Fox, Abhimitra Meka, Mallikar-
jun BR, Fangneng Zhan, Tim Weyrich, Bernd Bickel,
Hanspeter Pfister, Wojciech Matusik, Mohamed Elgharib,
et al. Lite2relight: 3d-aware single image portrait relighting.
In ACM SIGGRAPH 2024 Conference Papers, pages 1–12,
2024. 16
[85] Elad Richardson, Matan Sela, and Ron Kimmel. 3d face
reconstruction by learning from synthetic data. In 2016
fourth international conference on 3D vision (3DV), pages
460–469. IEEE, 2016. 3
[86] Christos Sagonas, Epameinondas Antonakos, Georgios Tz-
imiropoulos, Stefanos Zafeiriou, and Maja Pantic. 300 faces
in-the-wild challenge: Database and results. Image and
vision computing, 47:3–18, 2016. 3
[87] Shunsuke Saito, Gabriel Schwartz, Tomas Simon, Junxuan
Li, and Giljoo Nam. Relightable gaussian codec avatars.
In Proceedings of the IEEE/CVF conference on computer
vision and pattern recognition, pages 130–141, 2024. 3, 4,
9, 10
[88] Kripasindhu Sarkar, Marcel C B¨uhler, Gengyan Li, Daoye
Wang, Delio Vicini, J´er´emy Riviere, Yinda Zhang, Sergio
Orts-Escolano, Paulo Gotardo, Thabo Beeler, et al. Litnerf:
Intrinsic radiance decomposition for high-quality view syn-
thesis and relighting of faces. In SIGGRAPH Asia 2023
Conference Papers, pages 1–11, 2023. 3
[89] Jack Saunders, Charlie Hewitt, Yanan Jian, Marek Kowal-
ski, Tadas Baltrusaitis, Yiye Chen, Darren Cosker, Virginia
Estellers, Nicholas Gyde, Vinay P. Namboodiri, and Ben-
jamin E Lundell. Gasp: Gaussian avatars with synthetic
priors, 2024. 3
[90] Zhijing Shao, Zhaolong Wang, Zhuang Li, Duotun Wang,
Xiangru Lin, Yu Zhang, Mingming Fan, and Zeyu Wang.
Splattingavatar: Realistic real-time human avatars with
mesh-embedded gaussian splatting. In Proceedings of the
IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 1606–1616, 2024. 3

<!-- page 20 -->
[91] Heyi Sun, Cong Wang, Tian-Xing Xu, Jingwei Huang, Di
Kang, Chunchao Guo, and Song-Hai Zhang. Svg-head:
Hybrid surface-volumetric gaussians for high-fidelity head
reconstruction and real-time editing. In Proceedings of the
IEEE/CVF International Conference on Computer Vision,
pages 13326–13335, 2025. 3
[92] Jingxiang Sun, Xuan Wang, Yong Zhang, Xiaoyu Li, Qi
Zhang, Yebin Liu, and Jue Wang. Fenerf: Face editing in
neural radiance fields. In Proceedings of the IEEE/CVF con-
ference on computer vision and pattern recognition, pages
7672–7682, 2022. 3
[93] Tiancheng Sun, Jonathan T Barron, Yun-Ta Tsai, Zexiang
Xu, Xueming Yu, Graham Fyffe, Christoph Rhemann, Jay
Busch, Paul E Debevec, and Ravi Ramamoorthi. Single
image portrait relighting. ACM Trans. Graph., 38(4):79–1,
2019. 3
[94] Kartik Teotia, Hyeongwoo Kim, Pablo Garrido, Marc Haber-
mann, Mohamed Elgharib, and Christian Theobalt. Gaus-
sianheads: End-to-end learning of drivable gaussian head
avatars from coarse-to-fine representations. ACM Transac-
tions on Graphics (TOG), 43(6):1–12, 2024. 3
[95] Kartik Teotia, Xingang Pan, Hyeongwoo Kim, Pablo
Garrido, Mohamed Elgharib, and Christian Theobalt.
Hq3davatar: High-quality implicit 3d head avatar. ACM
Transactions on Graphics, 43(3):1–24, 2024. 3
[96] Ayush Tewari, Michael Zollhoefer, Florian Bernard, Pablo
Garrido, Hyeongwoo Kim, Patrick Perez, and Christian
Theobalt. High-fidelity monocular face reconstruction based
on an unsupervised model-based face autoencoder. IEEE
transactions on pattern analysis and machine intelligence,
42(2):357–370, 2018. 3
[97] Ayush Tewari, Florian Bernard, Pablo Garrido, Gaurav
Bharaj, Mohamed Elgharib, Hans-Peter Seidel, Patrick
P´erez, Michael Zollhofer, and Christian Theobalt. Fml:
Face model learning from videos. In Proceedings of the
IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 10812–10822, 2019. 3
[98] Justus Thies, Michael Zollh¨ofer, and Matthias Nießner. De-
ferred neural rendering: Image synthesis using neural tex-
tures. Acm Transactions on Graphics (TOG), 38(4):1–12,
2019. 3
[99] Luan Tran and Xiaoming Liu. Nonlinear 3d face morphable
model. In Proceedings of the IEEE conference on computer
vision and pattern recognition, pages 7346–7355, 2018. 3
[100] Luan Tran, Feng Liu, and Xiaoming Liu. Towards high-
fidelity nonlinear 3d face morphable model. In Proceedings
of the IEEE/CVF Conference on Computer Vision and Pat-
tern Recognition, pages 1126–1135, 2019. 3
[101] Alex Trevithick, Matthew Chan, Michael Stengel, Eric Chan,
Chao Liu, Zhiding Yu, Sameh Khamis, Manmohan Chan-
draker, Ravi Ramamoorthi, and Koki Nagano. Real-time ra-
diance fields for single-image portrait view synthesis. ACM
Transactions on Graphics (TOG), 42(4):1–15, 2023. 3
[102] Cong Wang, Di Kang, He-Yi Sun, Shen-Han Qian, Zi-Xuan
Wang, Linchao Bao, and Song-Hai Zhang. Mega: Hybrid
mesh-gaussian head avatar for high-fidelity rendering and
head editing. arXiv preprint arXiv:2404.19026, 2024. 3, 15
[103] Jie Wang, Jiu-Cheng Xie, Xianyan Li, Feng Xu, Chi-Man
Pun, and Hao Gao.
Gaussianhead: High-fidelity head
avatars with learnable gaussian derivation. arXiv preprint
arXiv:2312.01632, 2023. 3
[104] Lizhen Wang, Zhiyuan Chen, Tao Yu, Chenguang Ma, Liang
Li, and Yebin Liu. Faceverse: a fine-grained and detail-
controllable 3d face morphable model from a hybrid dataset.
In Proceedings of the IEEE/CVF conference on computer
vision and pattern recognition, pages 20333–20342, 2022. 3
[105] Yifan Wang, Aleksander Holynski, Xiuming Zhang, and
Xuaner Zhang. Sunstage: Portrait reconstruction and re-
lighting using the sun as a light stage. In Proceedings of
the IEEE/CVF Conference on Computer Vision and Pattern
Recognition, pages 20792–20802, 2023. 4
[106] Zhou Wang, Alan C Bovik, Hamid R Sheikh, and Eero P Si-
moncelli. Image quality assessment: from error visibility to
structural similarity. IEEE transactions on image processing,
13(4):600–612, 2004. 11
[107] Zhibo Wang, Xin Yu, Ming Lu, Quan Wang, Chen Qian,
and Feng Xu. Single image portrait relighting via explicit
multiple reflectance channel modeling. ACM Transactions
on Graphics (ToG), 39(6):1–13, 2020. 3
[108] Erroll Wood, Tadas Baltruˇsaitis, Charlie Hewitt, Sebastian
Dziadzio, Thomas J Cashman, and Jamie Shotton. Fake it
till you make it: face analysis in the wild using synthetic
data alone. In Proceedings of the IEEE/CVF international
conference on computer vision, pages 3681–3691, 2021. 3
[109] Erroll Wood, Tadas Baltruˇsaitis, Charlie Hewitt, Matthew
Johnson, Jingjing Shen, Nikola Milosavljevi´c, Daniel Wilde,
Stephan Garbin, Toby Sharp, Ivan Stojiljkovi´c, et al. 3d
face reconstruction with dense landmarks. In European
Conference on Computer Vision, pages 160–177. Springer,
2022. 3
[110] Jun Xiang, Xuan Gao, Yudong Guo, and Juyong Zhang.
Flashavatar: High-fidelity head avatar with efficient gaussian
embedding. In Proceedings of the IEEE/CVF Conference on
Computer Vision and Pattern Recognition, pages 1802–1812,
2024. 3
[111] Yuelang Xu, Benwang Chen, Zhe Li, Hongwen Zhang,
Lizhen Wang, Zerong Zheng, and Yebin Liu. Gaussian
head avatar: Ultra high-fidelity head avatar via dynamic
gaussians. In Proceedings of the IEEE/CVF conference on
computer vision and pattern recognition, pages 1931–1941,
2024. 3
[112] Shugo Yamaguchi, Shunsuke Saito, Koki Nagano, Yajie
Zhao, Weikai Chen, Kyle Olszewski, Shigeo Morishima,
and Hao Li. High-fidelity facial reflectance and geometry
inference from an unconstrained image. ACM Transactions
on Graphics (TOG), 37(4):1–14, 2018. 3
[113] Haotian Yang, Hao Zhu, Yanru Wang, Mingkai Huang, Qiu
Shen, Ruigang Yang, and Xun Cao. Facescape: a large-scale
high quality 3d face dataset and detailed riggable 3d face
prediction. In Proceedings of the ieee/cvf conference on
computer vision and pattern recognition, pages 601–610,
2020. 3
[114] Haotian Yang, Mingwu Zheng, Chongyang Ma, Yu-Kun
Lai, Pengfei Wan, and Haibin Huang. Vrmm: A volumetric

<!-- page 21 -->
relightable morphable head model. In ACM SIGGRAPH
2024 Conference Papers, pages 1–11, 2024. 3
[115] Tarun Yenamandra, Ayush Tewari, Florian Bernard, Hans-
Peter Seidel, Mohamed Elgharib, Daniel Cremers, and Chris-
tian Theobalt. i3dmm: Deep implicit 3d morphable model
of human heads. In Proceedings of the IEEE/CVF Confer-
ence on Computer Vision and Pattern Recognition, pages
12803–12813, 2021. 3
[116] Lijun Yin, Xiaozhou Wei, Yi Sun, Jun Wang, and Matthew J
Rosato. A 3d facial expression database for facial behavior
research. In 7th international conference on automatic face
and gesture recognition (FGR06), pages 211–216. IEEE,
2006. 3
[117] Jiawei Zhang, Zijian Wu, Zhiyang Liang, Yicheng Gong,
Dongfang Hu, Yao Yao, Xun Cao, and Hao Zhu. Fate: Full-
head gaussian avatar with textural editing from monocular
video. In Proceedings of the Computer Vision and Pattern
Recognition Conference, pages 5535–5545, 2025. 15
[118] Tianke Zhang, Xuangeng Chu, Yunfei Liu, Lijian Lin,
Zhendong Yang, Zhengzhuo Xu, Chengkun Cao, Fei Yu,
Changyin Zhou, Chun Yuan, et al. Accurate 3d face recon-
struction with facial component tokens. In Proceedings of
the IEEE/CVF international conference on computer vision,
pages 9033–9042, 2023. 3
[119] Xinjie Zhang, Xingtong Ge, Tongda Xu, Dailan He, Yan
Wang, Hongwei Qin, Guo Lu, Jing Geng, and Jun Zhang.
Gaussianimage: 1000 fps image representation and com-
pression by 2d gaussian splatting. In European Conference
on Computer Vision, 2024. 8
[120] Hang Zhao, Orazio Gallo, Iuri Frosio, and Jan Kautz. Loss
functions for image restoration with neural networks. IEEE
Transactions on computational imaging, 3(1):47–57, 2016.
11
[121] Zhongyuan Zhao, Zhenyu Bao, Qing Li, Guoping Qiu, and
Kanglin Liu.
Psavatar: a point-based morphable shape
model for real-time head avatar creation with 3d gaussian
splatting. arXiv e-prints, pages arXiv–2401, 2024. 3
[122] Yufeng Zheng, Victoria Fern´andez Abrevaya, Marcel C
B¨uhler, Xu Chen, Michael J Black, and Otmar Hilliges.
Im avatar: Implicit morphable head avatars from videos.
In Proceedings of the IEEE/CVF conference on computer
vision and pattern recognition, pages 13545–13555, 2022. 3
[123] Yufeng Zheng, Wang Yifan, Gordon Wetzstein, Michael J
Black, and Otmar Hilliges. Pointavatar: Deformable point-
based head avatars from videos.
In Proceedings of the
IEEE/CVF conference on computer vision and pattern recog-
nition, pages 21057–21067, 2023. 3, 4
[124] Hao Zhou, Sunil Hadap, Kalyan Sunkavalli, and David W
Jacobs. Deep single-image portrait relighting. In Proceed-
ings of the IEEE/CVF international conference on computer
vision, pages 7194–7202, 2019. 3
[125] Xiangyu Zhu, Zhen Lei, Xiaoming Liu, Hailin Shi, and
Stan Z Li. Face alignment across large poses: A 3d solution.
In Proceedings of the IEEE conference on computer vision
and pattern recognition, pages 146–155, 2016. 3
[126] Yilin Zhu, Dalton Omens, Haodi He, and Ron Fedkiw. De-
mocratizing the creation of animatable facial avatars, 2024.
10
[127] Yiyu Zhuang, Hao Zhu, Xusen Sun, and Xun Cao. Mofan-
erf: Morphable facial neural radiance field. In European
conference on computer vision, pages 268–285. Springer,
2022. 3
[128] Wojciech Zielonka, Timo Bolkart, and Justus Thies. Instant
volumetric head avatars. In Proceedings of the IEEE/CVF
conference on computer vision and pattern recognition,
pages 4574–4584, 2023. 3
