<!-- page 1 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
1
Duplex-GS: Proxy-Guided Weighted Blending for
Real-Time Order-Independent Gaussian Splatting
Weihang Liu, Yuke Li, Yuxuan Li, Jingyi Yu, Fellow, IEEE, Xin Lou, Senior Member, IEEE,
Abstract—3D Gaussian Splatting (3DGS) achieves photore-
alistic rendering but incurs substantial overhead due to the
global sorting required for α-blending, which results in noticeable
“popping” artifacts and hinders deployment on edge devices.
While sort-free Order-Independent Transparency (OIT) methods
circumvent sorting, they introduce “transparency” artifacts and
suffer from inefficiency due to the absence of physical constraints.
To address these limitations, we present Duplex-GS, a dual-
hierarchy framework that leverages proxy-guided spatial organi-
zation and a novel hybrid renderer that combines α-blending with
reformulated Weighted-Sum Rendering (WSR). We introduce
explicit ellipsoidal cell proxies to encapsulate local Gaussians,
which enables efficient proxy-level rasterization. This strategy
drastically reduces the overhead associated with global sorting.
Furthermore, we propose a physically grounded WSR scheme
with cell-level early termination, which retrieves the physical
constraints absent in prior OIT-based 3DGS methods, effectively
eliminating both popping and transparency artifacts. Extensive
experiments on diverse real-world datasets demonstrate the
robustness of Duplex-GS across scenarios spanning multi-scale
training views and large-scale environments. Quantitatively, our
method delivers high-fidelity real-time rendering, outperforming
prior OIT-based 3DGS methods by 1.5×– 4× in speed, while
reducing radix-sort cost by 29.8% – 86.9% compared with con-
ventional α-blending without compromising visual quality.
Index
Terms—Novel
View
Synthesis,
Gaussian
Splatting,
Order-Independent Transparency, Real-Time Rendering
I. INTRODUCTION
N
OVEL view synthesis (NVS) and real-time rendering
have attracted significant attention in both academia and
industry, with broad applications in video games, virtual reality
(VR) [1], and 3D scene reconstruction [2]–[9]. Inspired by the
groundbreaking Neural Radiance Field (NeRF) [10], learning-
based methods have substantially advanced the realism of
digital content, narrowing the gap between the virtual and
real worlds. However, these methods often entail consider-
able computational overhead. The emergence of 3D Gaussian
Splatting (3DGS) [11], [12] marks another milestone, enabling
photorealistic and real-time rendering of radiance fields via
rasterization, a paradigm akin to the graphics pipeline in
modern graphics processing units (GPUs).
Despite the impressive reconstruction and rendering capa-
bilities of 3DGS, a primary limitation is its need for an ever-
increasing number of Gaussian primitives to fit all training
views. This results in substantial and irregular memory access
during rendering, as costly view-dependent sorting operations
This work has been submitted to the IEEE for possible publication.
Copyright may be transferred without notice, after which this version may
no longer be accessible.
over long sequences impose considerable computational and
memory overhead [13], [14]. Moreover, the sorting process
can introduce visible “popping” artifacts [15], as illustrated in
Fig. 1. Collectively, these limitations hinder the scalability of
3DGS for large-scale applications and restrict its deployment
on resource-constrained platforms such as mobile phones and
VR devices.
More recently, sort-free Gaussian Splatting [16] has incor-
porated Order-Independent Transparency (OIT) [17], [18] into
the Gaussian Splatting framework, eliminating the need for
sorting in the rasterization pipeline by employing Weighted
Sum Rendering (WSR) [19]. This effectively eliminates pop-
ping artifacts and has been successfully demonstrated on mo-
bile devices [16]. However, as illustrated in Fig. 1, the absence
of physical constraints leads to “transparency” artifacts and
increased rendering time, particularly in large-scale scenes,
due to the accumulation of redundant Gaussian primitives and
lack of early termination when encountering opaque objects
in the blending phase.
Neural Gaussian frameworks [20], [21] enhance storage
efficiency by using “anchor” points to encode local Gaussians
via shared MLPs. However, they still require sorting the de-
coded Gaussians for α-blending, which is costly on resource-
constrained devices [14]. Moreover, the lack of explicit spatial
constraints allows Gaussians to deviate from their anchors
(Fig. 2), complicating the representation.
This paper presents Duplex-GS, a novel framework for
modeling 3D scenes using explicit proxies with defined vis-
ible regions and a tailored hybrid rendering paradigm. Our
approach integrates the benefits of α-blending and WSR to
eliminate artifacts while maintaining real-time performance.
First, we encode scenes using ellipsoidal proxies, termed
“cells”, which replace the anchors used in the original neural
Gaussian framework. By constraining neural Gaussians to re-
side within their respective cells, rasterization is performed at
the cell level to guide subsequent Gaussian blending. Second,
activated cells are decoded into Gaussians via shared MLPs.
By restoring physical constraints absent in previous OIT-based
3DGS [16], we introduce a physically grounded WSR strategy
that enables early termination and replaces non-commutative
blending operations with a parallelizable weighted sum.
This hybrid design offers two key advantages. First, the
significantly smaller population of cell proxies compared to
Gaussians enables our cell-level rasterization strategy to drasti-
cally reduce the memory and computational overhead of global
radix sorting. Second, we restore physical constraints absent
0000–0000/00$00.00 © 2021 IEEE
arXiv:2508.03180v2  [cs.CV]  14 Nov 2025

<!-- page 2 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
2
View-1
View-2
Weights
Depth
View-1
View-2
Weights
Depth
α-Blending (Popping artifacts)
GS-1, Depth-1
GS-2, Depth-2
GS-3, Depth-3
Weight-1
Weight-2
Weight-3
Weights Calculation
Rasterization
Weighted Sum Rendering (Transparency artifacts)
Transparency
artifacts
Sort-based Rendering
3DGS (Siggraph 2023)
Sort-free Gaussian Splatting
LC-WSR (ICLR 2025)
Rasterization
Popping artifacts
Popping artifacts
Tiling
Tiling
Replication
Tile-1. GS-1
Tile-1. GS-2
Tile-2. GS-1
Tile-2. GS-2
Tile-3. GS-2
Tile-4. GS-2
Tile-2. GS-3
Tile-3. GS-3
Tile-4. GS-3
Tile-1. GS-1
Tile-1. GS-2
Tile-2. GS-1
Tile-2. GS-2
Tile-3. GS-2
Tile-4. GS-2
Tile-2. GS-3
Tile-3. GS-3
Tile-4. GS-3
Replication
Tile-1. GS-1
Tile-1. GS-2
Tile-2. GS-1
Tile-2. GS-2
Tile-3. GS-2
Tile-4. GS-2
Tile-2. GS-3
Tile-3. GS-3
Tile-4. GS-3
Sorting 
Tile-1. GS-1
Tile-1. GS-2
Tile-2. GS-1
Tile-2. GS-2
Tile-3. GS-2
Tile-4. GS-2
Tile-2. GS-3
Tile-3. GS-3
Tile-4. GS-3
Tile-1. GS-1
Tile-1. GS-2
Tile-2. GS-1
Tile-2. GS-2
Tile-3. GS-2
Tile-4. GS-2
Tile-2. GS-3
Tile-3. GS-3
Tile-4. GS-3
Tile-1. GS-1
Tile-1. GS-2
Tile-2. GS-1
Tile-2. GS-2
Tile-3. GS-2
Tile-4. GS-2
Tile-2. GS-3
Tile-3. GS-3
Tile-4. GS-3
Sorting 
Tile-1. GS-1
Tile-1. GS-2
Tile-2. GS-1
Tile-2. GS-2
Tile-3. GS-2
Tile-4. GS-2
Tile-2. GS-3
Tile-3. GS-3
Tile-4. GS-3
Tile-1. GS-1
Tile-1. GS-2
Tile-2. GS-1
Tile-2. GS-2
Tile-3. GS-2
Tile-4. GS-2
Tile-2. GS-3
Tile-3. GS-3
Tile-4. GS-3
Tiling
Replication
Tile-1. GS-1
Tile-1. GS-2
Tile-2. GS-1
Tile-2. GS-2
Tile-3. GS-2
Tile-4. GS-2
Tile-2. GS-3
Tile-3. GS-3
Tile-4. GS-3
Sorting 
Tile-1. GS-1
Tile-1. GS-2
Tile-2. GS-1
Tile-2. GS-2
Tile-3. GS-2
Tile-4. GS-2
Tile-2. GS-3
Tile-3. GS-3
Tile-4. GS-3
Tile-1. GS-1
Tile-1. GS-2
Tile-2. GS-1
Tile-2. GS-2
Tile-3. GS-2
Tile-4. GS-2
Tile-2. GS-3
Tile-3. GS-3
Tile-4. GS-3
1
2
3
2
1
3
Early Termination
View 
Rotation
1
2
3
2
1
3
Early Termination
View 
Rotation
Fig. 1. Motivation of Duplex-GS. (Top) 3DGSs are rendered via α-blending for a long tile-Gaussian sequence. However, sudden changes in viewing angle can
cause abrupt changes in the blending order and the corresponding weights, resulting in noticeable popping artifacts. (Bottom) The sort-free LC-WSR method
eliminates the sorting stage through WSR paradigm. However, the absence of physical constraints leads to transparency artifacts and efficiency degradation,
as blending continues unnecessarily for opaque surfaces.
in prior OIT-based 3DGS method, which facilitates cell-level
early termination and removes both popping and transparency
artifacts simultaneously.
In summary, the contributions of this work are as follows:
• We propose a dual-layered Gaussian hierarchy com-
prising ellipsoidal proxy cells and 3D Gaussians. This
structure enables artifact-free, real-time 3D reconstruction
while maintaining the parallelizability of WSR.
• Cell rasterization (layer I): We introduce ellipsoidal
cells with adaptive geometric properties to spatially or-
ganize neural Gaussians. A novel cell-level rasteriza-
tion strategy is proposed, which significantly reduces
the memory and computational overhead associated with
global radix sorting.
• Physically grounded WSR blending (layer II): We
incorporate physical constraints into the WSR method to
blend local Gaussians, inherently avoiding popping and
transparency artifacts. Building on this, we introduce a
cell-level early termination scheme that further acceler-
ates rendering.
• We provide a high-performance CUDA implementation
of our WSR-based Gaussian splatting framework. Ex-
perimental results demonstrate that our method achieves
competitive rendering speed and superior visual fidelity
on consumer-grade hardware.
II. RELATED WORK
A. Neural Representation for 3D Scene
Traditional scene reconstruction methods like SfM [22],
[23] and MVS [24], [25] struggle with texture-less regions
and lighting variations. NeRF [10] enabled photorealistic
reconstruction from sparse images, with subsequent efficient
variants [26]–[28] making real-time rendering feasible on edge
devices [29], [30]. 3DGS [11] marked a breakthrough by using
explicit anisotropic Gaussians for fast rendering, though its
computational and memory demands limit its deployment on
resource-constrained platforms. A clear trend shows that more
explicit representations improve speed at the cost of memory,
leading to hybrid approaches [20], [26], [31]–[35] that balance
this trade-off. For example, Instant-NGP [26] uses a multi-
resolution hash table to reduce MLP burden, Scaffold-GS [20]
encodes neural Gaussians via anchors to reduce model size
while maintaining quality. However, these methods still rely
on the conventional α-blending pipeline that requires sorting
Gaussians by depth. This step complicates implementation and
introduces visual popping artifacts [15].
B. Efficient Neural Rendering
While NeRF is primarily constrained by high computational
demands, the practical deployment of 3DGS is bottlenecked
by its extensive number of Gaussian primitives and frequent
memory access requirements [13], [14]. Existing efforts to
optimize the original α-blending pipeline in 3DGS broadly
fall into three categories: 1) Applying model compression

<!-- page 3 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
3
(a) Proxy anchor vs. Proxy cell
(b) Artifacts elimination
(c) Time and space complexity
Improvement for 
WSR kernel
Improvement for 
WSR kernel
Proxy Anchor
GS1
GS2
GS3
Proxy Cell
GS1
GS2
GS3
GS1
GS2
GS3
t
t + 1
t
t + 1
a-blending 
LC-WSR (ICLR 2025)
Ours
Ours
Popping Artifact
Transparency 
Artifact
t
t + 1
t
t + 1
a-blending 
LC-WSR (ICLR 2025)
Ours
Ours
Popping Artifact
Transparency 
Artifact
Fig. 2.
Overview of the proposed Duplex-GS. Our approach is built on a dual-hierarchy structure that introduces ellipsoidal cells as proxies for local
Gaussians. (a) Explicit Cell Proxies. Unlike abstract anchor points, our geometrically defined proxy cells are directly utilized for rasterization, guiding the
subsequent Gaussian blending process. (b) Hybrid Rendering Paradigm. By synergistically combining α-blending with physically grounded WSR, our
method simultaneously eliminates both popping and transparency artifacts. (c) The integration of cell rasterization (Sec. IV) and physically grounded WSR
(Sec. V) achieves significant improvements over prior OIT-based Gaussian splatting methods in both rendering accuracy and computational efficiency.
techniques, such as Level-of-Detail (LOD) strategy [21], [36]–
[38], encoding schemes [20], [39], [40], as well as pruning
and quantization [41]–[43]. 2) Optimizing critical operators
through CUDA-based implementations [44]–[48] or dedicated
hardware acceleration units [49]. 3) Replacing Gaussian ker-
nels with more efficient representation such as linear ker-
nals [50] and half-Gaussian kernel [51].
A few works have attempted to revise the core render-
ing paradigm itself by exploring efficient alternatives to α-
blending. StochasticSplats [52] introduces a stochastic trans-
parency paradigm which enables efficient rendering using
OpenGL shaders at the risk of controllable quality degradation.
Sort-free Gaussian Splatting [16] introduces a Weighted Sum
Rendering (WSR) pipeline, which eliminates popping artifacts
and achieves faster rendering on mobile devices for small-scale
scenes. Nevertheless, its lack of physical constraints leads to
transparency artifacts and introduces unnecessary computation
when rendering opaque surfaces.
C. Order Independent Transparency
OIT [17], [18] is a foundational graphics technique inte-
grated into modern GPUs to enable the correct compositing
of transparent fragments without requiring explicit depth sort-
ing prior to rasterization. Early approaches, such as Depth
Peeling [53], A-buffer [54], and Multi-Layer Alpha Blend-
ing (MLAB) [55], successfully achieve OIT but often in-
cur significant time or memory overhead. Weighted Blended
OIT [19] offers a more efficient alternative by approximating
the integration of transparency in a single render pass, storing
weighted sums of color and opacity with carefully designed
blending weights. And this method has been applied to 3DGS
rendering [16]. However, the absence of physical constraints
in [16] degrades both visual quality and rendering efficiency.
In contrast, the proposed Duplex-GS framework restores the
physically grounded transmittance in proxy-level, enabling
early termination to halt compositing upon encountering fully
opaque surfaces with weighted blended OIT. As a result,
Duplex-GS attains rendering quality and speed on par with
state-of-the-art (SOTA) 3DGS models on high-end GPUs,
while exhibiting strong potential for deployment on resource-
constrained edge devices by alleviating the huge overhead of
the view-adaptive sorting stage.
III. PRELIMINARIES AND OVERVIEW
A. Preliminaries
1) Neural Gaussian:
3DGS [11] models scenes using
anisotropic 3D Gaussian primitives and renders images
through a rasterization based paradigm. Building upon 3DGS,
Scaffold-GS [20] introduces anchors as local encoding proxies,
which emit neural Gaussians decoded from latent features to
effectively represent local scene structure. Specifically, each
anchor emits a predefined set of K neural gaussians, whose
centers are given by:
µn,k = xn + Opos
n,k · Sn,
(1)
where n ∈{1, 2, ..., N} indexes the anchors, k ∈{1, 2, ...K}
indexes the neural Gaussians per anchor, xn denotes the center
of anchor-n, and µn,k represents the center of the emitted
neural Gaussian-k. Opos
n,k is the learned offset scaled by Sn.
Additionally, the opacities of the K neural Gaussians are
decoded from the latent feature fn, viewing distance δn and
direction rn via a scene-wise MLP
{σn,1, ..., σn,K} = Fσ(fn, δn, rn),
(2)

<!-- page 4 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
4
(a) Encoding scenes with cells 
Layer I: Cell Proxy for 3DGS (Sec. IV)
(b) Rasterization in the cell level 
(c) Blending with Physically grounded WSR 
Order-Independent WSR inside Cell
α-Blending outside Cell
Layer II: Physical Weighted Sum Rendering (Sec. V)
(c) Blending with Physically grounded WSR 
Order-Independent WSR inside Cell
α-Blending outside Cell
Layer II: Physical Weighted Sum Rendering (Sec. V)
cell-0
cell-1
cell-2
MLP 
decoder
MLP 
decoder
Rendered View 
GT
Fig. 3. Illustration of the proposed Duplex-GS pipeline. (Layer I) Ellipsoidal cells act as proxies to spatially organize local Gaussians. This structure enables
efficient cell-level rasterization, significantly reducing the overhead of view-adaptive global sorting. (Layer II) Intersected cells are decoded into Gaussians
and blended with the proposed physically grounded WSR. The final color is computed by first determining cell-level weights via α-blending, then aggregating
the Gaussians inside each cell in an order-independent WSR manner.
where Fσ is the shared opacity decoder where the output is
activated by Tanh. Similarly, the other attributes of each neural
Gaussians, including color cn,k, scales sn,k and quaternions
qn,k, are predicted by separate MLPs Fc, Fs, Fq, respectively.
Consequently, rendering proceeds via a tile based Gaussian
rasterization technique, which employs radix sort to blend M
ordered points
C(x′) =
X
i∈M
T α-blending
i
ciαi,
αi = σiG′
i(x′),
(3)
where x′ denotes the 2D coordinates of the queried pixel,
G′
i(x′) is the projected 2D gaussian kernel, and T α-blending
i
denotes the transmittance
T α-blending
i
=
i−1
Y
j=1
(1 −αj).
(4)
2) Weighted Sum Rendering: Inspired by OIT, a widely
adopted technique for rendering non-opaque media in tradi-
tional graphics pipelines, sort-free Gaussian Splatting inte-
grates this concept into 3DGS, producing the final image as
C = cBwB + PN
i=1 ciαiw(di)
wB + PN
i=1 αiw(di)
,
(5)
where cB and wB denote the background color and the
learnable background weights respectively, and di indicates
the depths of the i-th 3D Gaussians.
By employing this WSR formulation, the non-commutative,
computationally intensive sorting stage, traditionally required
for compositing, is eliminated. This significantly enhances
the potential for parallelization and accelerates rendering.
Specifically, the Linear Correction Weighted-Sum Rendering
(LC-WSR) function w(di) achieve best performance which is
defined as
w(di) = T LC-WSR
i
· vi,
(6)
T LC-WSR
i
= max

0, 1 −di
τ

,
(7)
where τ and vi are the learnable parameters. This function
formulates the decay trend w.r.t. the depths of the rendering
Gaussians.
B. Overview
We introduce a novel framework featuring a tailored encod-
ing and rendering paradigm, as illustrated in Fig. 3. Our ap-
proach is structured in two primary stages. First, 3D scenes are
modeled using ellipsoidal cells, which act as proxies that emit
Gaussians with coherent features inside their coverage. This is
coupled with a hybrid rendering paradigm that integrates the
advantages of α-blending and WSR, establishing a globally
ordered yet locally unordered scene structure. Specifically,
rasterization is first performed at the proxy layer to compute
a blending weight for each cell in α-blending manner. The
emitted Gaussians are then rendered using a revised WSR
paradigm.
This pipeline conducts sorting at the cell level, establishing
a coarse spatial order for patches of Gaussians. This strategy

<!-- page 5 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
5
: Blocked by Early Termination
: Overlap Confusion (Sec. V-A)
GS Rasterization
GS Rasterization
GS Rasterization
Cell Rasterization
Cell Rasterization
Cell Rasterization
Fig. 4. Comparison between rasterization of GS and cell. Unlike the original
α-blending which processes each Gaussian individually, our method performs
rasterization and early termination at the coarser cell level, where each cell
encapsulates multiple Gaussians. The order confusion caused by overlap
among cells is discussed in Sec. V-A.
drastically reduces the computational burden of performing a
radix sort on every individual Gaussian primitive (Sec. IV).
Within each cell, Gaussians remain locally unsorted, making
the order-independent WSR paradigm naturally suitable for
their blending. This design eliminates popping artifacts, as
the rendering result is locally invariant to the Gaussian order.
Furthermore, by reintroducing physical constraints into the
OIT-based renderer, a physically grounded transmittance decay
is guaranteed, as shown in Fig. 5, which removes the trans-
parency artifacts inherent in the vanilla OIT-based Gaussian
Splatting [16] (Sec. V) as well as enables early termination in
cell-level to accelerate rendering.
IV. LAYER I: CELL PROXY FOR 3DGS
While neural Gaussian frameworks [20], [21] have achieved
remarkable reconstruction accuracy, they still rely on conven-
tional α-blending operations as the introduced proxy anchors
are points without concrete geometric interpretation. We intro-
duce ellipsoidal cells with explicit visible regions as the prox-
ies. Based on this representation, a cell rasterization strategy
is introduced, enabling efficient and lightweight rasterization.
A. Cell Proxy
Unlike anchors, which are points lacking geometric struc-
ture, each cell is represented as an ellipsoid that covers
several neural 3D Gaussians whose physical properties are
dynamically decoded from a trainable feature.
Initialization begins with SfM points P ∈RN×3. We
generate the initial cells from these points, centering each
one in accordance with the method described in [21]. Every
cell is parameterized by position xn, scales Sn, quaternions
Qn, defining its visible region, and a calibration scalar vn
(discussed in Sec. V-A). In the dual-layered hierarchy, each
cell is further associated with a latent feature vector fn
that encodes local scene information, and emits K neural
Gaussians as described in Eq. 1. The attributes of these K
neural Gaussians, including color cn,k, scales ratio Oscale
n,k and
quaternions qn,k, are decoded from the latent feature fn, along
with the viewing distance δn and viewing direction dn, via
shared scene-wise MLPs.
{cn,1, ..., cn,K} = Fc(fn, δn, dn),
(8)
{Oscale
n,1 , ..., Oscale
n,K} = Fs(fn, δn, dn),
(9)
{qn,1, ..., qn,K} = Fq(fn, δn, dn).
(10)
To ensure that each Gaussian center lies within the visible
region of its corresponding cell, we constrain the offset pa-
rameter Opos
n,k to the range [−1, 1]. We propose that cells are
likely to emit Gaussians with similar geometric properties. So
scales of Gaussians are derived under the supervision of Sn:
sn,k = Oscale
n,k ∗Sn,
(11)
where the output of Fs is activated by sigmoid to restrict the
ratio Oscale
n,k to the range (0, 1). Based on Eq.11, the scales of
cells can be directly optimized. While the quaternions unable
to optimize in the similar way, as they denote the orientation of
the clustered Gaussians. To align regions of cell and Gaussians,
the cell quaternions are updated as the weighted average of the
associated Gaussians’ orientation
Qn = norm(
K
X
k
qn,k ∗σn,k).
(12)
Additionally, to restrict that the Gaussian regions fully locate
inside the cell region, the maximum of Oscale
n,k
is further
clamped by
Oscale
n,k = min

Oscale
n,k , 1 −||Opos
n,k||

.
(13)
As illustrated in Fig. 3, the proposed neural Gaussians are
constrained to reside strictly within their corresponding cell
regions. Leveraging this property, the cell projections can
effectively guide the Gaussian blending process.
B. Cell Rasterization
Conventional α-blending renders views by rasterizing 3D
Gaussians onto the image plane via splatting, a process that
necessitates a global Gaussian traversal and sort. We fun-
damentally reformulate this pipeline by introducing a cell-
level rasterization technique, where ellipsoidal cells, rather
than individual Gaussians, serve as the primary rendering
primitives. As illustrated in Fig. 4, this approach significantly
reduces the number of primitives handled. Specifically, each
cell defines a bounded visible region; only cells intersecting
the viewing frustum are selected and decoded into neural 3D
Gaussians.
This proxy-guided design inherently ensures spatial align-
ment between the cell distribution and the underlying Gaus-
sians, confining computationally intensive rasterization opera-
tions exclusively to the coarser cell level. Operating within a

<!-- page 6 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
6
0
0.1
0.2
Gaussian weight
0
10
20
30
Gaussian depth
0
0.1
0.2
Gaussian weight
0
10
20
30
Gaussian depth
0
0.1
0.2
Gaussian weight
0
10
20
30
Gaussian depth
Gaussian depth
 a-blending
Gaussian depth
 a-blending
Gaussian depth
 a-blending
0
0.5
1
TLC-WSR
0
10
20
30
0
0.5
1
Tα-blending
0
10
20
30
0
0.5
1
Tcell
0
10
20
30
α-blending
Ours
WSR
0
0.6
4.56
4.57
0
0.6
4.56
4.57
0
0.6
4.58 4.62
0
0.6
4.58 4.62
0
0.5
1
TLC-WSR
0
10
20
30
0
0.5
1
Tα-blending
0
10
20
30
0
0.5
1
Tcell
0
10
20
30
α-blending
Ours
WSR
0
0.6
4.56
4.57
0
0.6
4.58 4.62
Fig. 5. Comparison of three different transmittance: LC-WSR (Eq. 7), vanilla
α-blending (Eq. 4) and ours (Eq. 16). By reintroducing physical constraints,
our model produces a transmittance curve similar to that of α-blending,
establishing it as a reliable criterion for early termination. Furthermore, the
proposed transmittance is not strictly monotonic with depth, confirming the
local order-independent nature of Gaussian blending in our framework.
tile-based paradigm, visible cells are assigned to corresponding
tiles, and a radix sort is applied to the cell sequence. Since
the number of cells is orders of magnitude smaller than that
of Gaussians, this strategy yields substantial reductions in
both memory consumption and computational overhead for
the rasterization process.
V. LAYER II: PHYSICAL WEIGHTED SUM RENDERING
Duplex-GS reconstructs 3D scenes using ellipsoidal cells,
which enable rasterization and sorting at a coarse cell level to
significantly reduce rasterization overhead. However, this ap-
proach forgoes the explicit per-Gaussian depth sorting required
by the original α-blending pipeline, which is grounded in
physical light transport models. This introduces an ambiguity
in the blending order. The Sort-free Gaussian method [16],
an OIT extension of 3DGS, demonstrates that high-fidelity
view synthesis can be achieved through a weighted sum of
Gaussians, governed by mathematical rather than physical
constraints. This paradigm is highly suitable for graphics
rendering pipelines in modern GPU and resource-constrained
devices. Nevertheless, abandoning the physical blending model
introduces transparency artifacts that degrade visual quality,
and the lack of early termination further compromises render-
ing efficiency.
In this section, we integrate the OIT based rendering
paradigm with a cell based Gaussian model, retrieving physical
constraints for WSR based 3DGS.
A. Physical OIT Blending for 3DGS
Although
the
WSR
paradigm
[16]
provides
a
mathematically-grounded
rendering
model,
it
lacks
a
physical foundation. Consequently, the blending weight αi in
Eq. 5 does not correspond to a physically meaningful opacity
and is unconstrained, often exceeding unity. This formulation
not only introduces transparency artifacts but also precludes
the use of early termination when blending opaque surfaces,
limiting its efficiency.
Within this coarse-ordered structure obtained from cell
rasterization, we redefine α as an opacity weighted by the
Gaussian kernel (Eq. 3), constraining its value to the physi-
cally plausible range of [0, 1]. The final rendered view C is
computed according to the weighted sum rendering formula:
C =
PN
n=1 wn
PK
k=1 αn,kcn,k
PN
n=1 wn
PK
k=1 αn,k
,
(14)
where wn denotes the weight of cell-n, derived from the cell-
level sorting results. A sophisticated WSR kernel for each cell,
wn can then be defined as:
wn = vn · T cell
n ,
(15)
where T cell
n
denotes the cell-level transmittance, which is
efficiently obtained by sorting the sparsely distributed cells,
and it decays based on the accumulated opacity from preceding
cells:
T cell
n
=
n−1
Y
i=1
K
Y
k=1
(1 −vi · αi,k),
(16)
where a learnable calibration scalar vi is introduced to address
the ambiguity arising from non-uniform spatial distribution
and potential inter-cell overlaps, as illustrated in Fig. 4. Since
cell occlusion relationships are view-dependent, we param-
eterize vi using spherical harmonic coefficients to capture
its directional variation. The resulting Eq. 14 shows that our
framework produces model which is ordered outside cells and
order-independent inside each cell.
The opacity distribution in a 3D scene is typically sparse,
implying that the accumulated transmittance is physically
modeled by a step-function which suddenly changes encoun-
tering points with high opacity rather than a gradual decay. To
validate this theory, we provide three transmittance paradigms
and the resulting Gaussians weights in Fig. 5. LC-WSR
simulates transmittance with a linear function of Gaussian
depth. However, this model is physically inconsistent, as it
is derived from purely mathematical constraints. In contrast,
our method produces a weight distribution similar to vanilla
α-blending without requiring a precise per-Gaussian depth
order, which eliminates transparency artifacts for that the
transmittance decays rapidly when encountered opaque object.
Furthermore, the rendering of Gaussian primitives is locally
order-independent, as the transmittance does not strictly de-
crease with depth. This property forms the cornerstone for the
elimination of popping artifacts.
B. Early Termination for Cell Based 3DGS
As defined in Eq. 16, the cell-level transmittance T cell
n
de-
cays towards zero during front-to-back rendering, eliminating
transparency artifacts. This provides a natural mechanism for
early termination: the blending process is halted in cell level
once T cell
n
falls below a predefined threshold ϵ, as illustrated
in Fig. 4. This approach effectively accelerates rendering.

<!-- page 7 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
7
Tile Grid
AABB
AABB
False Positive
Positive tile
Negative tile
Interval between layers
(a) Mismatch between cell and GS
(b) False positive skip
Pixel Grid
GS region
cell region
Fig. 6. Illustration of mismatch between cell and Gaussian. (a) The interval
between layers influence the efficiency of cell rasterization. (b) False positive
regions are skipped to alleviate the speed degradation from the mismatch.
Unlike prior WSR methods for 3DGS, our formulation restores
explicit physical meaning to the opacity parameter σn,k by
constraining it to the physically plausible range of [0, 1], which
means the empirical threshold can be directly transferred to our
model. This enforcement of physical plausibility subsequently
facilitates more effective pruning and regularization during the
training process.
VI. OPTIMIZATION STRATEGIES FOR CELL BASED
GAUSSIAN SPLATTING
The cell search rasterization inevitably introduces redundant
3D Gaussians during the blending stage, due to the discrep-
ancies that arise between the spatial intervals of cells and
the emitted neural Gaussians as shown in Fig. 6a. As the
efficiency of cell search rasterization is contingent upon the
degree of coherence between the visible regions of a cell
and its associated Gaussians, we provide several engineering-
driven strategies to facilitate training of Duplex-GS.
A. False Positive Skip
Tile-based Rendering (TBR) is widely adopted in modern
GPUs and is also utilized in 3DGS rasterization. However, this
approach often introduces a substantial number of redundant
false-positive Gaussians. This problem is further exacerbated
in cell-based Gaussian frameworks due to the spatial mismatch
between cell regions and the actual coverage of Gaussians.
To mitigate the associated performance degradation, we intro-
duce a pixel-level radius based culling strategy to eliminate
unnecessary Gaussian kernel computations. Specifically, as
illustrated in Fig. 6, a lightweight axis-aligned bounding box
(AABB) check is employed: Gaussians are excluded from
the blending operation if the pixel lies outside their respec-
tive AABBs. This efficient early-exit mechanism significantly
reduces redundant computation and accelerates the overall
rendering process.
B. Geometric Correction via Neural Gaussians
In addition to skipping false-positive Gaussians to improve
efficiency, maximizing the overlap between each cell and its
emitted neural Gaussians further reduces the number of re-
dundant Gaussians. To achieve better geometric alignment, we
dynamically define the cell’s quaternion as a weighted average
of the quaternions associated with its emitted Gaussians, as
described in Eq. 12. Moreover, to ensure an even spatial
distribution of Gaussians within each cell, the cell centers are
periodically updated using
xn =
PK
k=1 µn,k
K
.
(17)
As cell scales are differentiable via Eq. 11, the three-
dimensional covariances and positions of first-layer cells are
learned in accordance with the updates to the second-layer
Gaussians.
C. Cell Position Reset
Following adaptive density control [11], we grow new cells
at Gaussians with high view-space positional gradients. Unlike
abstract anchors [20], [21], our cells have explicit geometry.
To decouple existing cells from newly introduced ones, the
offsets of the significant Gaussians are reset to zero after cell
growth, i.e., their positions are reinitialized to the centers of
the corresponding cells.
D. Perceptual Loss
The loss function for optimizing 3DGS is typically formu-
lated as a combination of ℓ1 and SSIM [56] losses, which
respectively capture pixel-level reconstruction error and struc-
tural similarity. As proven in GAN-based models, these pixel-
wise image differences results in solutions with high signal-
to-noise ratios, which are perceptually rather smooth and less
convincing [57], [58]. We additionally incorporate a perceptual
loss term for training Gaussian based models. The overall loss
is defined as
L = (1 −λ1 −λ2)L1 + λ1LSSIM + λ2LLPIPS,
(18)
where L1, LSSIM and LLPIPS denote ℓ1, structural similar-
ity and perceptual loss respectively. While the inclusion of
the perceptual loss yields rendering results with improved
perceptual quality, its computation relies on convolutional
neural networks (CNNs), which increases the training time. To
address this, we compute the perceptual loss every 20 training
iterations, which substantially alleviates the additional com-
putational overhead without noticeably increasing the overall
training time.
VII. EXPERIMENTAL RESULTS
A. Experimental Settings
1) Datasets:
We conducted extensive experiments on
scenes from multiple public datasets, adopting the standard
configurations established by 3DGS [11].
Our evaluation encompasses 13 standard benchmarks:
nine
scenes
from
Mip-NeRF360
[59],
two
from
Tanks&Temples [60], and two from DeepBlending [61].
To further assess robustness, we tested on 10 challenging
scenes from BungeeNeRF [63], featuring multi-scale outdoor
environments,
and
VR-NeRF
[1],
containing
large-scale
intricate interiors. Additionally, we included the large-scale

<!-- page 8 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
8
TABLE I
QUANTITATIVE COMPARISONS ON REAL-WORLD DATASET [59]–[61]. DUPLEX-GS ACHIEVES COMPETITIVE RENDERING QUALITY WHILE REDUCING
MODEL SIZE COMPARED TO THE BASELINES. THE BEST PERFORMANCE FOR EACH METRIC IS HIGHLIGHTED.
Method
Mip-NeRF360
Tanks&Temples
DeepBlending
PSNR↑
SSIM↑
LPIPS↓
Storage↓
PSNR↑
SSIM↑
LPIPS↓
Storage↓
PSNR↑
SSIM↑
LPIPS↓
Storage↓
Mip-NeRF3601 [59]
27.69
0.792
0.237
-
22.22
0.759
0.257
-
29.40
0.901
0.245
-
3DGS1 [11]
27.52
0.813
0.222
750.2 MB
23.57
0.845
0.180
431.4 MB
29.61
0.900
0.251
662.7 MB
Mip-Splatting1 [62]
27.61
0.816
0.215
838.4 MB
23.96
0.856
0.171
500.4 MB
29.56
0.901
0.243
736.8 MB
Scaffold-GS1 (K = 10) [20]
27.73
0.812
0.226
171.0 MB
24.09
0.858
0.165
147.7 MB
30.42
0.912
0.246
111.2 MB
Scaffold-GS1 (K = 5) [20]
27.74
0.811
0.230
205.3 MB
24.53
0.863
0.162
177.7 MB
30.26
0.911
0.242
143.4 MB
Octree-GS1 (K = 10) [21]
27.88
0.816
0.216
142.7 MB
24.60
0.864
0.157
77.8 MB
30.44
0.911
0.239
95.5 MB
Octree-GS1 (K = 5) [21]
27.73
0.813
0.227
124.5 MB
24.47
0.861
0.168
73.9 MB
30.06
0.908
0.250
75.1 MB
LC-WSR2 [16]
27.21
0.800
0.219
1312.0 MB
23.22
0.832
0.186
672.7 MB
29.90
0.901
0.243
810.7 MB
StocSplats3(16 SPP) [52]
26.25
0.714
0.351
-
-
-
-
-
-
-
-
-
Ours (K = 10)
27.90
0.813
0.216
152.2 MB
24.26
0.867
0.150
124.8 MB
30.30
0.910
0.249
89.7 MB
Ours (K = 5)
27.74
0.802
0.218
104.4 MB
24.32
0.867
0.138
112.2 MB
30.26
0.909
0.236
94.7 MB
1 Experiments are conducted using the official public repository, with no modifications except for iteration settings as described in Sec. VII-A4.
2 Experiments are conducted with our own implementation, which has been recognized by the author of [16]. Codes are available at https://github.com/
LiYukeee/sort-free-gs.
3 Results from original paper (code unavailable). Missing data reflects source omissions.
TABLE II
QUANTITATIVE COMPARISONS ON BUNGEENERF [63] AND VR-NERF [1] DATASETS. ADDITIONAL EXPERIMENTS ASSESS PERFORMANCE ON
MULTI-SCALE RENDERING AND THE RECONSTRUCTION OF INTRICATE INDOOR DETAILS. DUPLEX-GS ACHIEVES HIGH-QUALITY RENDERING WITH
COMPACT MODEL SIZES. THE BEST RESULT FOR EACH METRIC IS HIGHLIGHTED.
Method
BungeeNeRF
VR-NeRF: apartment
VR-NeRF: kitchen
PSNR↑
SSIM↑
LPIPS↓
Storage↓
PSNR↑
SSIM↑
LPIPS↓
Storage↓
PSNR↑
SSIM↑
LPIPS↓
Storage↓
3DGS1 [11]
27.71
0.915
0.099
1654.1 MB
30.98
0.922
0.212
368.1 MB
31.73
0.933
0.185
443.6 MB
Mip-Splatting1 [62]
28.21
0.922
0.096
1108.8 MB
31.49
0.929
0.201
442.8 MB
32.19
0.939
0.177
484.3 MB
Scaffold-GS1 (K = 10) [20]
27.36
0.901
0.122
328.5 MB
30.70
0.927
0.182
840.1 MB
31.20
0.932
0.166
658.5 MB
Scaffold-GS1 (K = 5) [20]
27.32
0.898
0.130
353.7 MB
31.30
0.932
0.170
740.4 MB
31.05
0.930
0.171
593.2 MB
Octree-GS1 (K = 10) [21]
27.07
0.901
0.117
351.0 MB
31.19
0.922
0.212
217.7 MB
32.33
0.939
0.157
372.7 MB
Octree-GS1 (K = 5) [21]
26.93
0.894
0.133
329.9 MB
31.34
0.921
0.224
165.3 MB
31.40
0.929
0.181
403.0 MB
LC-WSR2 [16]
26.94
0.903
0.111
1670.2 MB
31.84
0.935
0.169
1543.2 MB
32.32
0.937
0.158
1482.7 MB
Ours (K = 10)
28.80
0.920
0.093
319.2 MB
31.79
0.927
0.218
191.7 MB
32.17
0.934
0.191
176.2 MB
Ours (K = 5)
28.66
0.914
0.098
262.8 MB
32.27
0.932
0.178
299.0 MB
32.38
0.940
0.157
269.8 MB
1 Experiments are conducted using the official public repository, with no modifications except for iteration settings as described in Sec. VII-A4.
2 Experiments are conducted with our own implementation, which has been recognized by the author of [16]. Codes are available at https://github.com/
LiYukeee/sort-free-gs.
aerial scene Block All scene from MatrixCity [64], which
comprises 5,621 training and 741 testing images covering an
urban area of 2.7 km2.
All experiments were performed at a resolution of 1K.
2) Metrics: We evaluate the reconstruction fidelity with
PSNR, SSIM [56] and LPIPS [65], which are commonly used
in image quality measurement. We also record the model size,
frame per second (FPS) and runtime breakdown as indicators
of storage overhead and rendering speed tested on RTX 4090
GPU. Additionally, the consumptions of the radix sort are
listed to address the effectiveness of our method in reducing
the sorting overhead comparing with α-blending, which is a
bottleneck for edge devices. We also report FPS on a laptop
with RTX 3060 GPU to verify the applicability of our method
in mid-range devices.
3) Baselines: We compare our method with several SOTA
approaches, including 3DGS, Mip-NeRF360, Scaffold-GS,
Octree-GS, LC-WSR, and StocSplats. Among these, LC-WSR
and StocSplats serve as representatives of the OIT based ren-
dering paradigm for Gaussian splatting, while the remaining
methods employ the conventional α-blending pipeline used in
vanilla 3DGS.
The results for StocSplats are sourced directly from its
original publication, which reports performance on the Mip-
NeRF 360 dataset using an RTX 4090 GPU. As its training
code and pre-trained models are not publicly available, we
are unable to evaluate its performance on other benchmarks;
the corresponding entries in our comparisons are therefore left
blank.
4) Implementation Details: All baseline models are op-
timized using a combined loss function comprising the ℓ1

<!-- page 9 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
9
Ours
LC-WSR
Octree-GS
Scaffold-GS
Mip-Splatting
3DGS
GT
Fig. 7. Qualitative comparisons of Duplex-GS and competing baselines on Mip-NeRF360 [59] dataset. The proposed Duplex-GS successfully removes the
“transparency” artifacts for the WSR rendering kernel while maintaining the ability to reconstruct fine details.
TABLE III
QUANTITATIVE COMPARISONS ON MATRIXCITY. DUPLEX-GS ACHIEVES
HIGHEST ACCURACY ACROSS ALL METRIC IN SUCH LARGE-SCALE AERIAL
SCENARIOS WHILE MAINTAINING COMPETITIVE EFFICIENCY.
Method
MatrixCity
PSNR↑
SSIM↑
LPIPS↓
#GS/#Proxy↓
FPS↑
Time [h]↓
3DGS1 [11]
27.03
0.808
0.310
10206 K
66
2.60
Scaffold-GS [20]
26.82
0.811
0.288
4829 K
113
2.31
Octree-GS [21]
25.18
0.738
0.397
4082 K
128
2.61
Octree-GS* [21]
26.61
0.812
0.292
8010 K
79
-
LC-WSR [16]
26.34
0.782
0.340
7841 K
34
3.86
Ours (K = 5)
27.40
0.826
0.260
4165 K
119
2.21
* Officially released pretrained model.
and SSIM losses. The weighting factor λ1 in Eq. 18 is
set to 0.2. In contrast, a perceptual loss is computed every
20 training iterations with a weight λ2 of 0.5. For neural
Gaussian-based methods, including Scaffold-GS, Octree-GS,
and our proposed Duplex-GS, experiments are conducted with
encoding dimensions K set to 5 and 10, respectively.
Small-scale scenes are trained for 40,000 iterations, with
densification concluding at iteration 25,000. Large-scale
scenes are trained for 100,000 iterations, with densification
ending at iteration 50,000.
B. Results Analysis
We first validate our method by showing that it achieves
competitive accuracy across all datasets while maintaining
high efficiency. The results are shown in Tab. I and Tab. II.
1) Quantitative Results: Tab. I presents a comprehensive
comparison of our method with several SOTA baselines on
three real-world datasets. On the Mip-NeRF360 dataset, our
approach achieves the highest PSNR when K = 10, out-
performing all baselines. While Mip-Splatting and Octree-GS
attain slightly higher SSIM values (0.816), our method yields
competitive SSIM (0.813) and achieves improved perceptual
quality, as evidenced by a lower LPIPS (0.216). Remarkably,
our model also demonstrates strong storage efficiency, requir-
ing significantly less memory than methods such as 3DGS and
Mip-Splatting, both of which demand over 750 MB.
On the Tanks&Temples and DeepBlending datasets, al-
though the PSNR values of our approach are marginally lower,
it delivers superior visual quality, attaining the highest SSIM
or lowest LPIPS compared to other models. Notably, when
compared to LC-WSR, the OIT variant of Gaussian Splatting,
our method achieves better performance across all metrics and
datasets, showing the effectiveness of the OIT paradigm in
Gaussian Splatting on CUDA based high-end GPUs.
To further assess our method under challenging scenarios
involving multi-scale training views and large-scale datasets,
we conduct experiments on the BungeeNeRF, VR-NeRF and
MatrixCity datasets (results shown in Tab. II and Tab. III). On
BungeeNeRF, our approach achieves the highest PSNR and
lowest LPIPS when K = 10, and remains highly competitive
with K = 5, attaining the smallest model size among all
baselines. The two scenes within VR-NeRF are large-scale,
intricate indoor environments containing thousands of training
images. Experimental results indicate that OIT based rendering
consistently outperforms sort-based α-blending approaches for
such cases. On the MatrixCity dataset, our method achieves the
highest accuracy across all metrics (PSNR/SSIM/LPIPS) while
maintaining competitive efficiency with the most efficient
baseline (128 FPS vs. 119 FPS) and the smallest training time.
2) Qualitative Results: We present qualitative results and
comparisons with SOTA baselines to demonstrate the ef-
fectiveness of our proposed method in artifact removal and
detail preservation. As illustrated in Fig. 7 and Fig. 12 using
examples from the Mip-NeRF360 dataset, our method elimi-
nates the transparency artifacts observed in the previous OIT
based LC-WSR, while maintaining intricate scene details. For
multi-scale and large-scale scenarios, as shown in Fig. 8, the
proposed Duplex-GS successfully captures fine details, even in
texture-less and marginal regions. Additionally, our approach
effectively removes popping artifacts, benefiting from the OIT
blending kernel (see Fig. 11).
3) Efficiency Analysis: Tab. IV provides a comparison of
rendering speeds, measured in FPS, between our method
and several state-of-the-art baselines across four benchmark

<!-- page 10 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
10
Ours
LC-WSR
Octree-GS
Scaffold-GS
Mip-Splatting
3DGS
GT
Fig. 8. Qualitative comparisons of Duplex-GS and competing baselines on BungeeNeRF [59] and VR-NeRF [1] datasets. the proposed Duplex-GS successfully
captures fine details, even in textureless and marginal regions.
TABLE IV
EFFICIENCY ANALYSIS OF DUPLEX-GS AND COMPETING BASELINES,
REPORTING THE FPS AT 1K RESOLUTION ON RTX 4090 GPU.
Method
Mip-NeRF360
Tan.&Tem.
DeepBlend.
BungeeNeRF
3DGS [11]
149
142
145
52
Scaffold-GS [20]
150
129
185
72
Octree-GS [21]
183
159
271
114
LC-WSR [16]
77
89
114
31
StocSplats3 [52]
125
-
-
-
Ours (K = 5)
184
147
232
124
datasets. Our approach consistently achieves the highest or
highly competitive FPS on all datasets. On the Mip-NeRF360
dataset, our method achieves 184 FPS, surpassing all other
baselines and comparable to the fastest prior approach, Octree-
GS (183 FPS). For the Tanks&Temples dataset, our method
obtains 147 FPS, demonstrating performance close to the best-
performing baseline. While on the DeepBlending dataset, our
FPS of 232 is similarly on par with the leading method. Most
notably, on the BungeeNeRF dataset, our method achieves
124 FPS, a considerable improvement over existing baselines.
These results highlight the efficiency and scalability of our
approach, demonstrating real-time rendering capability and
practical superiority in intricate and multi-scale scenarios.
Tab. V presents a runtime breakdown to elucidate the
mechanisms of our hybrid renderer. The analysis reveals
that while LC-WSR benefits from hardware graphics pipeline
compatibility, it performs suboptimally on TBR architectures
due to redundant Gaussian primitives introduced in rendering
(exemplified in Fig. 5) and a lack of physical constraints.
In contrast, our method achieves a significant acceleration
in the rasterization and sorting stages. This gain is directly
attributable to our coarse-grained processing of cell proxies,
which drastically reduces the number of primitives handled
compared to per-Gaussian methods. This efficiency introduces
a trade-off: the blending phase exhibits increased latency.
This is an expected consequence of our design, which retains
sequential blending for cells and may process redundant
Gaussians by operating on cell-based groups (of size K) rather
than individual Gaussians. Despite this localized overhead, our
approach achieves the highest overall rendering speed, demon-
strating the effectiveness of the proposed hybrid paradigm.
Radix sort is employed in 3DGS to determine the explicit
ordering of Gaussian primitives, sorting b-digit numbers with
m possible values in O (b · (n + m)) time and O(n + m)
space. Notably, the sequence length n contributes linearly to
the overall complexity. To evaluate the effectiveness of our
approach in reducing the computational and memory require-
ments of view-adaptive sorting, we record the sorting length
and corresponding memory consumption during the radix sort
procedure. Compared with methods adhering to conventional
α-blending paradigm, the results, presented in Tab. VI, show
that our method successfully mitigates the sorting overhead
by introducing cell proxies, thereby demonstrating superior
efficiency.
4) Hyperparameter Analysis: We give analysis on the influ-
ence on the hyperparameter K, which controls the number of
Gaussians decoded per cell. Since the opacity σ, decoded via
Fσ and activated by a Tanh function, must satisfy σ > 0 for a
Gaussian to be considered valid and included in rendering, it
directly regulates the number of active primitives. The results
show that while varying K leads to only minor deviations in
reconstruction accuracy, it substantially impacts computational
efficiency. As illustrated in Fig. 9, increasing K results in more
Gaussians being activated during rendering, which slows down
the blending stage (Fig. 9-a). Conversely, a higher K reduces
the number of proxies involved, thereby accelerating the
rasterization process (Fig. 9-b). This trade-off elucidates the
performance characteristics of our hybrid renderer: the slower
blending speed compared to α-blending-based frameworks and
significant acceleration over LC-WSR are attributable to the
number of valid Gaussians (Fig. 9-a), Furthermore, the results
confirm that our cell-based framework exploits spatial sparsity
more effectively than anchor-based approaches, as evidenced
by the fewer proxies located within the same viewing frustum
(Fig. 9-b).
C. Ablation Studies
1) Cell vs. Anchor: The introduction of the ellipsoidal cell
represents a key innovation, enabling efficient proxy rasteriza-

<!-- page 11 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
11
TABLE V
RUNTIME BREAKDOWN (MS) ON MIPNERF360.
Method
Stage
bicycle
bonsai
counter
flowers
garden
kitchen
room
stump
treehill
AVE
LC-WSR
rasterization
7.0177
2.7192
3.2817
3.8094
7.0134
4.5389
2.8045
4.1043
5.7666
4.5618
blending
10.5629
4.2739
4.0905
4.9504
8.9972
6.0351
4.7305
5.2737
8.6236
6.5042
sum
17.5806
6.9932
8.3722
8.7599
16.0106
10.5741
7.5350
9.3779
14.3903
11.0660
Octree-GS
decode
0.0027
0.0024
0.0030
0.0035
0.0038
0.0035
0.0018
0.0019
0.0021
0.0027
rasterization
0.4232
0.3942
0.4723
0.3498
0.4280
0.4598
0.4497
0.3083
0.3823
0.4075
sorting
0.6793
0.5985
0.8814
0.4757
0.6933
0.8888
0.7727
0.3011
0.4941
0.6427
blending
1.3343
1.2240
1.4663
1.0070
1.4140
1.5561
1.5236
0.8118
1.0878
1.2695
sum
2.4394
2.2191
2.8231
1.8367
2.5391
2.9082
2.7477
1.4230
1.9663
2.3225
Ours
decode
0.0028
0.0027
0.0028
0.0025
0.0032
0.0030
0.0023
0.0023
0.0023
0.0027
rasterization
0.2562
0.2214
0.2387
0.2047
0.2200
0.2377
0.1944
0.2284
0.2580
0.2289
sorting
0.3799
0.4169
0.6360
0.1576
0.2714
0.5857
0.3576
0.1465
0.1925
0.3493
blending
1.7981
1.3834
1.8776
0.9951
1.6763
1.6698
2.1289
0.8722
1.3549
1.5285
sum
2.4371
2.0243
2.7552
1.3600
2.1709
2.4963
2.6832
1.2493
1.8078
2.1093
0
100
200
Training Epoch
0
1
2
3
106
0
100
200
Training Epoch
1.4
1.6
1.8
2
2.2
2.4
105
LC-WSR (27.00/60)
LC-WSR (27.00/60)
Octree-GS, K=20 (27.59/104)
Octree-GS, K=10 (27.50/135)
Octree-GS, K=5 (27.46/166)
Octree-GS, K=20 (27.59/104)
Octree-GS, K=10 (27.50/135)
Octree-GS, K=5 (27.46/166)
Duplex-GS, K=20 (27.41/108)
Duplex-GS, K=10 (27.47/140)
Duplex-GS, K=5 (27.51/165)
Duplex-GS, K=20 (27.41/108)
Duplex-GS, K=10 (27.47/140)
Duplex-GS, K=5 (27.51/165)
(a) Number of involved Gaussians
(b) Number of involved proxies
#GS inside viewing frustum
#Proxy inside viewing frustum
Fig. 9. Performance analysis with different hyperparameter K on garden sce-
nario from Mip-NeRF 360 dataset, which calculates metric (PSNR [dB]/FPS),
the number of valid Gaussians and proxies inside a same viewing frustum
during training. (a) The valid Gaussians is number of Gaussians with σ > 0,
indicating the efficiency of blending phase. (b) The involved proxies is the
number of cells or anchors located inside the viewing frustum. The proposed
cell is more sparse than anchors, resulting in acceleration in rasterization stage.
TABLE VI
COMPARISONS ABOUT THE OVERHEAD OF RADIX SORT STAGE. THE
PROPOSED CELL RASTERIZATION CONSISTENTLY REDUCE BOTH THE TIME
AND SPACE CONSUMPTIONS COMPARED WITH α-BLENDING BASED
METHODS.
Method
Mip-NeRF360
BungeeNeRF
Sorting Length↓
Memory↓
Sorting Length↓
Memory↓
3DGS [11]
7,000,602
81.0 MB
21,798,876
255.0 MB
Scaffold-GS [20]
4,588,785
53.69 MB
6,901,347
80.74 MB
Octree-GS [21]
4,701,055
55.09 MB
5,480,410
64.14 MB
Ours
3,217,845
37.7 MB
2,843,604
33.3 MB
tion and physical grounded WSR-based blending. In contrast,
anchors adhere to the conventional α-blending pipeline, which
processes Gaussians individually. To validate the effectiveness
of cells in proxy rasterization, we conduct an ablation study
by replacing cells with anchor points while maintaining our
hybrid rendering paradigm and retraining the models. As
shown in Tab. VII, this anchor-based rasterization fails due
to the lack of well-defined visible regions, confirming the
necessity of our geometric cell structure.
2) Cell-level
Transmittance:
The
physically
grounded
transmittance, shown in Eq. 16, is the key innovation which
eliminates transparency artifacts as well as enable early termi-
nation. We replace it with the conventional LC-WSR blending
kernel in the proposed pipeline, which is marked as “w/o T cell”
in Tab. VII and Fig. 10. The absence of physical constraints
result in transparency artifacts and degraded accuracy.
3) Early Termination (ET): The introduction of the early
termination mechanism is a key advantage of our method
over LC-WSR, which selectively omit computations that have
negligible impact on the final rendered output with extremely
small transmittance. To visualize the mechanism, we record
the termination ratio with
rET = 1 −N rendered
N val
,
(19)
where N rendered denotes the number of Gaussians contributed
to the final color, N val denotes that of the total interacted valid
Gaussians along the ray. Since the proposed transmittance
achieves a decay pattern similar to α-blending (Fig. 5), we
maintain the same threshold value as used in vanilla 3DGS.
The results are visualized in Fig. 13. Our method demon-
strates termination behavior which closely matches that of α-
blending, whereas prior sort-free Gaussian Splatting methods
lack this feature. To evaluate its effectiveness, we conduct an
ablation study by disabling early termination during model
training. As shown in Tab. VII, enabling early termination
leads to improvements in both accuracy and efficiency.
4) Alignment Restriction: Unlike Gaussians whose geome-
try is directly optimized through blending operations, cells are
updated guided by Gaussians and several constraints (Eq. 12
and Eq. 13) are imposed to align coverage between cell and the
corresponding Gaussians. To show the effectiveness of these
conditions, we mute these restriction and the results are shown
in Tab. VII. The accuracy decreases as expected, however,
the rendering speed is improved, which offers a solution for

<!-- page 12 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
12
Full Method
w/o cell
w/o cell
w/o 
w/o 
w/o 
w/o ET
w/o ET
w/o alignment
w/o alignment
w/o 
w/o 
w/o 
Full Method
w/o cell
w/o 
w/o ET
w/o alignment
w/o 
Fig. 10. Visualization of ablation study. Quantitative results are shown in Tab. VII.
3DGS
Ours
Residual Map
3DGS
Ours
  
  
Fig. 11. Illustration of “popping” artifacts removal by recording the differ-
ences between contiguous timestep.
LC-WSR
Ours
LC-WSR
Ours
LC-WSR
Ours
LC-WSR
Ours
Fig. 12. Illustration of “transparency” artifacts removal.
resource-constrained platform for its significant acceleration
while maintaining competitive visual quality.
5) Order Confusion: As the sorting results of cell level
cannot reflect the exact order of Gaussians. we introduce
learnable parameter vn to compensate the ambiguity. We
train models without vn to show its effectiveness. The results
are shown in Tab. VII. By introducing vn, the accuracy is
Ours
3DGS
LC-WSR
Rendered image
   
Fig. 13. Visualization of the early termination mechanism. The existing OIT
3DGS method, LC-WSR, does not support early termination due to its sort-
free design. In contrast, Duplex-GS achieves termination results comparable
to those of vanilla 3DGS, without requiring an explicit Gaussian order.
TABLE VII
ABLATION EXPERIMENTS. VISUAL EXAMPLES ARE SHOWN IN FIG. 10.
Method
PSNR↑
SSIM↑
LPIPS↓
FPS↑
w/o cell
19.30
0.655
0.365
270
w/o T cell
26.60
0.790
0.231
212
w/o ET
27.66
0.801
0.220
155
w/o alignment
27.54
0.799
0.223
229
w/o vn
27.59
0.801
0.218
174
Full method
27.74
0.802
0.218
184
improved as more degree-of-freedom is introduced to handle
the overlap ambiguity among cells.
D. Performance on Mid-range GPUs
We test rendering performance on a laptop with RTX
3060 GPU to validate the practicability of our method on
mid-range devices. The results are shown in Tab. IV. Our
method consistently achieves highest rendering speed while
maintaining competitive visual quality.
VIII. LIMITATION AND CONCLUSION
This work presents a dual-hierarchy Gaussian model that
effectively resolves popping artifacts inherent in vanilla α-
blending and the transparency artifacts of WSR. By introduc-
ing geometric proxy and a hybrid rendering paradigm, our
approach substantially reduces the overhead associated with
global sorting while achieving real-time performance as well
as competitive visual quality.

<!-- page 13 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
13
TABLE VIII
EFFICIENCY ANALYSIS OF DUPLEX-GS AND COMPETING BASELINES ON
MIP-NERF360 DATASETS, REPORTING FPS AT 1K RESOLUTION ON A
LAPTOP WITH RTX 3060 GPU .
Method
3DGS
LC-WSR
Octree-GS
Ours (K=5)
Ours (w/o alignment)
FPS
42
21
47
49
72
Several limitations suggest directions for future work. First,
the geometric relationships between cells and their constituent
Gaussians require further optimization, as imperfect spatial
alignment can lead to performance degradation and redundant
calculation, as illustrated in Fig. 6. Second, the core WSR
operation within each cell is inherently order-independent,
presenting substantial, yet unexplored, parallel computing op-
portunities. Custom hardware accelerators based on FPGA or
ASIC can capitalize on this parallelism to achieve higher per-
formance and energy efficiency compared to general-purpose
GPUs, thereby facilitating deployment on resource-constrained
edge devices.
REFERENCES
[1] L. Xu, V. Agrawal, W. Laney, T. Garcia, A. Bansal, C. Kim,
S. Rota Bul`o, L. Porzi, P. Kontschieder, A. Boˇziˇc, D. Lin, M. Zollh¨ofer,
and C. Richardt, “VR-NeRF: High-Fidelity Virtualized Walkable
Spaces,” in Proc. ACM SIGGRAPH Asia, 2023.
[2] W. Liu, Y. Zhong, Y. Li, X. Chen, J. Cui, H. Zhang, L. Xu, X. Lou,
Y. Shi, J. Yu, and Y. Zhang, “CityGo: Lightweight Urban Modeling
and Rendering with Proxy Buildings and Residual Gaussians,” arXiv
preprint arXiv:2505.21041, 2025.
[3] W. Li, X. Pan, J. Lin, P. Lu, D. Feng, and W. Shi, “FRPGS: Fast,
Robust, and Photorealistic Monocular Dynamic Scene Reconstruction
with Deformable 3D Gaussians,” IEEE Trans. Circuits Syst. Video
Technol., pp. 1–1, 2025.
[4] Y. Yan, H. Lin, C. Zhou, W. Wang, H. Sun, K. Zhan, X. Lang, X. Zhou,
and S. Peng, “Street Gaussians: Modeling Dynamic Urban Scenes with
Gaussian Splatting,” in Proc. Eur. Conf. Comput. Vis., 2024.
[5] B. Huang, Z. Yu, A. Chen, A. Geiger, and S. Gao, “2D Gaussian
Splatting for Geometrically Accurate Radiance Fields,” in Proc. ACM
SIGGRAPH, 2024.
[6] Y. Niu, X. Li, and Y. Wang, “Stereo-Gaussian: Enhanced Sparse View
Gaussian Splatting with One Stereopair for Light-field 3D Display,”
IEEE Trans. Circuits Syst. Video Technol., 2025.
[7] J. Zhang, Y. Zheng, Z. Li, Q. Dai, and X. Yuan, “GBR: Generative
Bundle Refinement for High-fidelity Gaussian Splatting with Enhanced
Mesh Reconstruction,” IEEE Trans. Circuits Syst. Video Technol., 2025.
[8] T. Zhou, S. Chen, S. Wan, H. Lv, Z. Luo, and J. Wu, “GEDR:Gaussian-
Enhanced Detail Reconstruction for Real-Time High-Fidelity 3D Scene
Reconstruction,” IEEE Trans. Circuits Syst. Video Technol., 2025.
[9] Z. Guo, W. Zhou, L. Li, M. Wang, and H. Li, “Motion-Aware 3D
Gaussian Splatting for Efficient Dynamic Scene Reconstruction,” IEEE
Trans. Circuits Syst. Video Technol., vol. 35, no. 4, pp. 3119–3133, 2025.
[10] B. Mildenhall, P. P. Srinivasan, M. Tancik, J. T. Barron, R. Ramamoorthi,
and R. Ng, “NeRF: Representing Scenes as Neural Radiance Fields for
View Synthesis,” in Proc. Eur. Conf. Comput. Vis., 2020.
[11] B. Kerbl, G. Kopanas, T. Leimk¨uhler, and G. Drettakis, “3D Gaussian
Splatting for Real-Time Radiance Field Rendering,” ACM Trans. Graph.,
vol. 42, no. 4, 2023.
[12] Y. Bao, T. Ding, J. Huo, Y. Liu, Y. Li, W. Li, Y. Gao, and J. Luo, “3D
Gaussian Splatting: Survey, Technologies, Challenges, and Opportuni-
ties,” IEEE Trans. Circuits Syst. Video Technol., pp. 1–1, 2025.
[13] X. Feng, H. Wang, C. Tang, T. Wu, H. Yang, and Y. Liu, “1.78mJ/Frame
373fps 3D GS Processor Based on Shape-Aware Hybrid Architecture
Using Earlier Computation Skipping and Gaussian Cache Scheduler,”
in Proc. IEEE Int. Solid-State Circuits Conf., vol. 68, 2025, pp. 1–3.
[14] S. Song, S. Kim, W. Park, J. Park, S. An, G. Park, M. Kim, and H.-J.
Yoo, “IRIS: A 8.55mJ/frame Spatial Computing SoC for Interactable
Rendering and Surface-Aware Modeling with 3D Gaussian Splatting,”
in Proc. IEEE Int. Solid-State Circuits Conf., vol. 68, 2025, pp. 1–3.
[15] L. Radl, M. Steiner, M. Parger, A. Weinrauch, B. Kerbl, and M. Stein-
berger, “StopThePop: Sorted Gaussian Splatting for View-Consistent
Real-time Rendering,” ACM Trans. Graph., vol. 43, no. 4, 2024.
[16] Q. Hou, R. Rauwendaal, Z. Li, H. Le, F. Farhadzadeh, F. Porikli,
A. Bourd, and A. Said, “Sort-free gaussian splatting via weighted sum
rendering,” in Proc. Int. Conf. Learn. Represent., 2025.
[17] H. Meshkin, “Sort-Independent Alpha Blending,” GDC Talk, vol. 2,
no. 4, 2007.
[18] C. Everitt, “Interactive order-independent transparency,” White paper,
nVIDIA, vol. 2, no. 6, p. 7, 2001.
[19] M. McGuire and L. Bavoil, “Weighted Blended Order-Independent
Transparency,” J. Comput. Graph. Tech., vol. 2, no. 4, 2013.
[20] L. Li, Z. Shen, Z. Wang, L. Shen, and L. Bo, “Scaffold-GS: Structured
3D Gaussians for View-Adaptive Rendering,” in Proc. IEEE/CVF Conf.
Comput. Vis. Pattern Recog., 2024, pp. 4222–4231.
[21] K. Ren, L. Jiang, T. Lu, M. Yu, L. Xu, Z. Ni, and B. Dai, “Octree-
GS: Towards Consistent Real-time Rendering with LOD-Structured 3D
Gaussians,” IEEE Trans. Pattern Anal. Mach. Intell., 2025.
[22] N. Snavely, S. M. Seitz, and R. Szeliski, “Skeletal Graphs for Efficient
Structure from Motion,” in Proc. IEEE/CVF Conf. Comput. Vis. Pattern
Recog., 2008, pp. 1–8.
[23] J. L. Sch¨onberger and J.-M. Frahm, “Structure-from-Motion Revisited,”
in Proc. IEEE/CVF Conf. Comput. Vis. Pattern Recog., 2016, pp. 4104–
4113.
[24] Y. Furukawa and J. Ponce, “Accurate, Dense, and Robust Multiview
Stereopsis,” IEEE Trans. Pattern Anal. Mach. Intell., vol. 32, no. 8, pp.
1362–1376, 2010.
[25] Y. Yao, Z. Luo, S. Li, T. Fang, and L. Quan, “MVSNet: Depth Inference
for Unstructured Multi-view Stereo,” in Proc. Eur. Conf. Comput. Vis.,
2018, pp. 785–801.
[26] T. M¨uller, A. Evans, C. Schied, and A. Keller, “Instant Neural Graphics
Primitives with a Multiresolution Hash Encoding,” ACM Trans. Graph.,
vol. 41, no. 4, 2022.
[27] W. Liu, X. X. Zheng, Y. Li, T. Y. Al-Naffouri, J. Yu, and X. Lou,
“CoARF++: Content-Aware Radiance Field Aligning Model Complexity
With Scene Intricacy,” IEEE Trans. Vis. Comput. Graph., pp. 1–14, 2025.
[28] A. Chen, Z. Xu, A. Geiger, J. Yu, and H. Su, “TensoRF: Tensorial
Radiance Fields,” in Proc. Eur. Conf. Comput. Vis., 2022, pp. 333–350.
[29] Z. Chen, T. Funkhouser, P. Hedman, and A. Tagliasacchi, “MobileNeRF:
Exploiting the Polygon Rasterization Pipeline for Efficient Neural Field
Rendering on Mobile Architectures,” in Proc. IEEE/CVF Conf. Comput.
Vis. Pattern Recog., 2023, pp. 16 569–16 578.
[30] X. Xiao, Z. Zhang, G.-S. Xia, Z. Shao, J. Gong, and D. Li, “RTO-
LLI: Robust Real-Time Image Orientation Method With Rapid Multi-
level Matching and Third-Times Optimizations for Low-Overlap Large-
Format UAV Images.” IEEE Trans. Geosci. Remote Sens., 2025.
[31] S. Fridovich-Keil, A. Yu, M. Tancik, Q. Chen, B. Recht, and
A. Kanazawa, “Plenoxels: Radiance Fields without Neural Networks,”
in Proc. IEEE/CVF Conf. Comput. Vis. Pattern Recog., 2022, pp. 5501–
5510.
[32] J. Liu, L. Kong, J. Yan, and G. Chen, “Mesh-Aligned 3D Gaussian
Splatting for Multi-Resolution Anti-Aliasing Rendering,” IEEE Trans.
Circuits Syst. Video Technol., 2025.
[33] M. Wu, H. Dai, K. Yao, T. Tuytelaars, and J. Yu, “BG-Triangle:
B´ezier Gaussian Triangle for 3D Vectorization and Rendering,” in Proc.
IEEE/CVF Conf. Comput. Vis. Pattern Recog., 2025.
[34] J. Lin, J. Gu, L. Fan, B. Wu, Y. Lou, R. Chen, L. Liu, and J. Ye,
“HybridGS: Decoupling Transients and Statics with 2D and 3D Gaussian
Splatting,” in Proc. IEEE/CVF Conf. Comput. Vis. Pattern Recog., 2025.
[35] Q. Yang, L. Yang, G. V. D. Auwera, and Z. Li, “HybridGS: High-
Efficiency Gaussian Splatting Data Compression using Dual-Channel
Sparse Representation and Point Cloud Encoder,” in Proc. Int. Conf.
Mach. Learn., 2025.
[36] B. Kerbl, A. Meuleman, G. Kopanas, M. Wimmer, A. Lanvin, and
G. Drettakis, “A Hierarchical 3D Gaussian Representation for Real-Time
Rendering of Very Large Datasets,” ACM Trans. Graph., 2024.
[37] J. Cui, J. Cao, F. Zhao, Z. He, Y. Chen, Y. Zhong, L. Xu, Y. Shi,
Y. Zhang, and J. Yu, “LetsGo: Large-Scale Garage Modeling and Ren-
dering via LiDAR-Assisted Gaussian Primitives,” ACM Trans. Graph.,
vol. 43, no. 6, 2024.
[38] Y. Liu, C. Luo, L. Fan, N. Wang, J. Peng, and Z. Zhang, “CityGaussian:
Real-time High-quality Large-Scale Scene Rendering with Gaussians,”
in Proc. Eur. Conf. Comput. Vis., 2025, pp. 265–282.

<!-- page 14 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
14
[39] W. Morgenstern, F. Barthel, A. Hilsmann, and P. Eisert, “Compact
3D Scene Representation via Self-Organizing Gaussian Grids,” arXiv
preprint arXiv:2312.13299, 2023.
[40] J. Zhang, F. Zhan, L. Shao, and S. Lu, “SOGS: Second-Order Anchor for
Advanced 3D Gaussian Splatting,” in Proc. IEEE/CVF Conf. Comput.
Vis. Pattern Recog., 2025.
[41] S. Niedermayr, J. Stumpfegger, and R. Westermann, “Compressed 3D
Gaussian Splatting for Accelerated Novel View Synthesis,” in Proc.
IEEE/CVF Conf. Comput. Vis. Pattern Recog., 2024, pp. 10 349–10 358.
[42] Z. Fan, K. Wang, K. Wen, Z. Zhu, D. Xu, and Z. Wang, “LightGaussian:
Unbounded 3D Gaussian Compression with 15x Reduction and 200+
FPS,” arXiv preprint arXiv:2312.13299, 2023.
[43] W. Liu, X. X. Zheng, J. Yu, and X. Lou, “Content-Aware Radiance
Fields: Aligning Model Complexity with Scene Intricacy Through
Learned Bitwidth Quantization,” in Proc. Eur. Conf. Comput. Vis., 2024.
[44] X. Huang, H. Zhu, Z. Liu, W. Lin, X. Liu, Z. He, J. Leng, M. Guo,
and Y. Feng, “SeeLe: A Unified Acceleration Framework for Real-Time
Gaussian Splatting,” arXiv preprint arXiv:2503.05168, 2025.
[45] V. Ye and A. Kanazawa, “Mathematical Supplement for the gsplat
Library,” arXiv preprint arXiv:2312.02121, 2023.
[46] S. Durvasula, A. Zhao, F. Chen, R. Liang, P. Kumar Sanjaya, and
N. Vijaykumar, “DISTWAR: Fast Differentiable Rendering on Raster-
based Rendering Pipelines,” arXiv preprint arXiv:2401.05345, 2023.
[47] G. Feng, S. Chen, R. Fu, Z. Liao, Y. Wang, T. Liu, Z. Pei, H. Li,
X. Zhang, and B. Dai, “FlashGS: Efficient 3D Gaussian Splatting for
Large-scale and High-resolution Rendering,” in Proc. IEEE/CVF Conf.
Comput. Vis. Pattern Recog., 2025.
[48] Y. Chen, J. Jiang, K. Jiang, X. Tang, Z. Li, X. Liu, and Y. Nie,
“DashGaussian: Optimizing 3D Gaussian Splatting in 200 Seconds,” in
Proc. IEEE/CVF Conf. Comput. Vis. Pattern Recog., 2025.
[49] J. Lee, S. Lee, J. Lee, J. Park, and J. Sim, “GSCore: Efficient Radiance
Field Rendering via Architectural Support for 3D Gaussian Splatting,”
in Proc. ACM Int. Conf. Archit. Support Program. Lang. Oper. Syst.,
2024.
[50] H. Chen, R. Chen, Q. Qu, Z. Wang, T. Liu, X. Chen, and Y. Y. Chung,
“Beyond Gaussians: Fast and High-Fidelity 3D Splatting with Linear
Kernels,” arXiv preprint arXiv:2411.12440, 2024.
[51] H. Li, J. Liu, M. Sznaier, and O. Camps, “3D-HGS: 3D Half-Gaussian
Splatting,” in Proc. IEEE/CVF Conf. Comput. Vis. Pattern Recog., 2025.
[52] S. Kheradmand, D. Vicini, G. Kopanas, D. Lagun, K. M. Yi,
M. Matthews, and A. Tagliasacchi, “StochasticSplats: Stochastic Ras-
terization for Sorting-Free 3D Gaussian Splatting,” in Proc. IEEE Int.
Conf. Comput. Vis., 2025.
[53] L. Bavoil and K. Myers, “Order Independent Transparency with Dual
Depth Peeling,” NVIDIA OpenGL SDK, vol. 1, no. 12, pp. 2–4, 2008.
[54] L. Carpenter, “The A-buffer, an Antialiased Hidden Surface Method,”
in Proc. ACM SIGGRAPH, 1984, pp. 103–108.
[55] M. Salvi and K. Vaidyanathan, “Multi-Layer Alpha Blending,” in Proc.
ACM SIGGRAPH Symp. Interact. 3D Graph. Games, 2014, pp. 151–
158.
[56] Z. Wang, A. Bovik, H. Sheikh, and E. Simoncelli, “Image Quality
Assessment: From Error Visibility to Structural Similarity,” IEEE Trans.
Image Process., vol. 13, no. 4, pp. 600–612, 2004.
[57] C. Ledig, L. Theis, F. Husz´ar, J. Caballero, A. Cunningham, A. Acosta,
A. Aitken, A. Tejani, J. Totz, Z. Wang, and W. Shi, “Photo-Realistic Sin-
gle Image Super-Resolution Using a Generative Adversarial Network,”
in Proc. IEEE/CVF Conf. Comput. Vis. Pattern Recog., 2017.
[58] X. Wang, K. Yu, S. Wu, J. Gu, Y. Liu, C. Dong, C. C. Loy, Y. Qiao,
and X. Tang, “ESRGAN: Enhanced Super-Resolution Generative Ad-
versarial Networks,” in Proc. Eur. Conf. Comput. Vis., 2018.
[59] J. T. Barron, B. Mildenhall, D. Verbin, P. P. Srinivasan, and P. Hedman,
“Mip-NeRF 360: Unbounded Anti-Aliased Neural Radiance Fields,” in
Proc. IEEE/CVF Conf. Comput. Vis. Pattern Recog., 2022, pp. 5855–
5864.
[60] A. Knapitsch, J. Park, Q.-Y. Zhou, and V. Koltun, “Tanks and Temples:
Benchmarking Large-Scale Scene Reconstruction,” ACM Trans. Graph.,
vol. 36, no. 4, 2017.
[61] P. Hedman, J. Philip, T. Price, J.-M. Frahm, G. Drettakis, and G. Bros-
tow, “Deep Blending for Free-Viewpoint Image-Based Rendering,” ACM
Trans. Graph., vol. 37, no. 6, 2018.
[62] Z. Yu, A. Chen, B. Huang, T. Sattler, and A. Geiger, “Mip-Splatting:
Alias-free 3D Gaussian Splatting,” in Proc. IEEE/CVF Conf. Comput.
Vis. Pattern Recog., June 2024, pp. 19 447–19 456.
[63] Y. Xiangli, L. Xu, X. Pan, N. Zhao, A. Rao, C. Theobalt, B. Dai, and
D. Lin, “BungeeNeRF: Progressive Neural Radiance Field for Extreme
Multi-scale Scene Rendering,” in Proc. Eur. Conf. Comput. Vis., 2022.
[64] Y. Li, L. Jiang, L. Xu, Y. Xiangli, Z. Wang, D. Lin, and B. Dai,
“MatrixCity: A Large-scale City Dataset for City-scale Neural Rendering
and Beyond,” in Proc. IEEE Int. Conf. Comput. Vis., 2023, pp. 3205–
3215.
[65] R. Zhang, P. Isola, A. A. Efros, E. Shechtman, and O. Wang, “The
Unreasonable Effectiveness of Deep Features as a Perceptual Metric,”
in Proc. IEEE/CVF Conf. Comput. Vis. Pattern Recog., 2018.
Weihang Liu received the B.S. and M.E. degree
in electronics and communication engineering in
2019 and 2022. He is currently working toward
the doctoral degree in electronic and information
engineering with School of Information Science
and Technology, ShanghaiTech University, Shang-
hai, China. His research interests include computer
graphics, computer vision and artificial intelligence.
Yuke Li received the B.S. degree in data sci-
ence from China University of Petroleum, Qingdao,
China, in 2024. He is currently pursuing the mas-
ter’s degree with ShanghaiTech University, Shang-
hai, China. His research interests include AI, neural
networks, and data science.
Yuxuan Li received the B.S. degree in microelec-
tronics science and engineering from Shanghai Uni-
versity in 2025. He is currently pursuing the doctoral
degree at ShanghaiTech University. His research
interests include computer graphics and computer
architecture.
Jingyi Yu (Fellow, IEEE) received the B.S. degree
from Caltech in 2000 and the Ph.D. degree from
MIT in 2005. He is currently the Vice Provost with
ShanghaiTech University. Before joining Shang-
haiTech University, he was a Full Professor with the
Department of Computer and Information Sciences,
University of Delaware. His current research inter-
ests include computer vision and computer graphics,
especially computational photography and noncon-
ventional optics and camera designs. He is a recip-
ient of the NSF CAREER Award and the AFOSR
YIP Award. He served as an Area Chair for many international conferences,
including CVPR, ICCV, ECCV, IJCAI, and NeurIPS. He was the Program
Chair of CVPR 2021 and will be the Program Chair of ICCV 2025.

<!-- page 15 -->
JOURNAL OF LATEX CLASS FILES, VOL. 14, NO. 8, AUGUST 2021
15
Xin Lou (Senior Member, IEEE) received the
B.Eng. degree in Electronic Information Technol-
ogy and Instrumentation from Zhejiang University
(ZJU), China, in 2010 and M.Sc. degree in System-
on-Chip Design from Royal Institute of Technology
(KTH), Sweden, in 2012 and PhD degree in Electri-
cal and Electronic Engineering from Nanyang Tech-
nological University (NTU), Singapore, in 2016.
Then he joined VIRTUS, IC Design Centre of
Excellence at NTU as a research scientist. He is
currently an Associate Professor with the School
of Information Science and Technology, ShanghaiTech University, Shanghai,
China. His research interests primarily focus on high-performance and energy-
efficient integrated circuits and systems for vision and graphics processing. Dr.
Lou serves as an Associate Editor of IEEE Transactions on Very Large Scale
Integration, and was an Associate Editor of IEEE Transactions on Circuits and
Systems II: Express Briefs (2022-2023), a Guest Editor of Associate Editor
of IEEE Transactions on Circuits and Systems I (2024).
