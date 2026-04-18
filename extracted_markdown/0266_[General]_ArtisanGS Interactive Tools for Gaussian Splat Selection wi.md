<!-- page 1 -->
ArtisanGS: Interactive Tools for Gaussian Splat Selection
with AI and Human in the Loop
CLEMENT FUJI TSANG, NVIDIA, Canada
ANITA HU, NVIDIA, Canada
OR PEREL, NVIDIA and University of Toronto, Canada
CARSTEN KOLVE, NVIDIA, France
MARIA SHUGRINA, NVIDIA and University of Toronto, Canada
Fig. 1. From messy kitchens to interactive objects: Our goal is to enable 3D practitioners to source objects from in-the-wild captures and work with them
for emerging downstream applications, such as editing and physics simulation. To touch the tip of the iceberg on this topic, we propose a suite of interactive
techniques for selection of objects and parts in 3D Gaussian Splat scenes, enabling applications like targeted editing.
Representation in the family of 3D Gaussian Splats (3DGS) are growing
into a viable alternative to traditional graphics for an expanding number
of application, including recent techniques that facilitate physics simula-
tion and animation. However, extracting usable objects from in-the-wild
captures remains challenging and controllable editing techniques for this
representation are limited. Unlike the bulk of emerging techniques, focused
on automatic solutions or high-level editing, we introduce an interactive
suite of tools centered around versatile Gaussian Splat selection and seg-
mentation. We propose a fast AI-driven method to propagate user-guided
2D selection masks to 3DGS selections. This technique allows for user in-
tervention in the case of errors and is further coupled with flexible manual
selection and segmentation tools. These allow a user to achieve virtually
any binary segmentation of an unstructured 3DGS scene. We evaluate our
toolset against the state-of-the-art for Gaussian Splat selection and demon-
strate their utility for downstream applications by developing a user-guided
local editing approach, leveraging a custom Video Diffusion Model. With
flexible selection tools, users have direct control over the areas that the AI
can modify. Our selection and editing tools can be used for any in-the-wild
capture without additional optimization.
Authors’ Contact Information: Clement Fuji Tsang, caenorst@hotmail.com, NVIDIA,
Canada; Anita Hu, anitah@nvidia.com, NVIDIA, Canada; Or Perel, orr.perel@gmail.
com, NVIDIA and University of Toronto, Canada; Carsten Kolve, carsten.kolve@gmail.
com, NVIDIA, France; Maria Shugrina, shumash@gmail.com, NVIDIA and University
of Toronto, Canada.
1
Introduction
Recent methods for multi-view capture, such as 3D Gaussian Splats
(3DGS) [Kerbl et al. 2023], have reduced the barrier around captur-
ing high-fidelity realistic 3D scenes. With other advances, such as
representation-agnostic physics simulation [Modi et al. 2024] and
generative capabilities [Yi et al. 2024], 3DGS representation and its
variants [Huang et al. 2024; Moenne-Loccoz et al. 2024] are on track
to become a feasible alternative to mesh-based graphics for many
interactive applications. For example, interactive 3D scenes could
be authored from videos captured in the wild; realistic simulation
environments for robotics could be created by simply recording the
real world. However, a tangible lack of tools for processing 3DGS
captures into interactive scenes, including fine segmentation and
targeted editing tools, hinders these applications in practice.
We propose ArtisanGS, a suite of AI-powered and user-driven
tools for flexible selection of 3DGS objects from unstructured in-
the-wild captures (§4). Our selection tools are designed to work in
conjunction with other applications (§6) needing local control like
’editing’. We enable workflows where 3DGS objects are separated
from the rest of the scan, processed and then re-composed into the
original 3d capture or novel environment - which in turn enables
interactive applications for games and robotics.
arXiv:2602.10173v1  [cs.CV]  10 Feb 2026

<!-- page 2 -->
2
•
Clement Fuji Tsang, Anita Hu, Or Perel, Carsten Kolve, and Maria Shugrina
Working with monolithic 3DGS captures is challenging due to
their unstructured nature. To enable object-based interactions, Gaus-
sians representing specific objects must be segmented. While sev-
eral prior works address AI-based semantic grouping and masking
of Gaussians (Tb.1), most require lengthy training and none offer
strategies to correct mistakes, which makes these methods difficult
to apply in practice. In contrast, emerging commercial tools (see
Supplemental) primarily target laborious manual operations. We
design versatile interactive tool that allows a user to work with
minimal-input AI-assisted 3D segmentation (often just one or two
clicks), diagnose and correct mistakes, and manually target specific
areas. We develop a clean and consistent treatment of 2D and 3D
selections in our toolkit design, enabling users to jump between
different selection modes. Together, these techniques enable 3D
artists to achieve nearly any desired 3D segmentation fast.
Flexible 3D selection empowers many applications (§6) that ben-
efit from targeted control. As one example, we develop local editing
of segmented 3DGS objects guided by user selections with a custom
object-centric Video Diffusion Model. We also show how selection
tools can facilitate guided scene orientation and enable scene setup
and material assignment for applications like physics simulation,
now possible directly over 3DGS objects [Modi et al. 2024].
In summary, our contributions are as follows:
• Interactive 3D segmentation method for 3DGS objects, pow-
ered by pre-trained 2D segmentation networks, requiring a
single click or 2D mask for any one view (no offline scene-
based optimization)
• Quantitative and qualitative evaluation of this selection
against baselines and commercial software
• Technique to allow users to diagnose and correct errors in
the above nearly automatic segmentation
• Interactive techniques allowing users to employ a 2D seg-
mentation network or traditional 2D segmentation tools for
manual clean-up of 3D segmentation
• Demonstration of possible applications that could be facili-
tated by flexible 3DGS selection
Our method can be applied to any messy in-the-wild-capture, with-
out requiring original training views or scene-specific pre-training.
We prototype an interface to show the utility of our selection and
segmentation toolkit design.
2
Related Work
2.1
Multi-View 3D Capture
Many recent methods focused on optimizing a 3D representation
of a scene based on multi-view photographs. Following a rich line
of work based on Neural Radiance Fields (NERFs) [Mildenhall et al.
2021], a recently popular 3D representation for multi-view 3D cap-
tures is 3D Gaussian Splatting (3DGS) [Kerbl et al. 2023]. While,
like NERF, vanilla 3DGS suffers from baked lighting, which be-
comes obvious during scene manipulation, many emerging works
are extending this representation to be more in line with physics
based rendering [Du et al. 2024; Gao et al. 2025; Liang et al. 2024;
Moenne-Loccoz et al. 2024]. Unlike NERF, its many variants [Müller
et al. 2022; Wang et al. 2023], and grid-based alternatives such as
[Fridovich-Keil et al. 2022], which are difficult to manipulate locally,
the explicit nature of 3DGS makes this representation family [Huang
et al. 2024; Kerbl et al. 2023; Moenne-Loccoz et al. 2024; Rong et al.
2024] convenient for editing and local transformations. This has led
to an exciting line of work that uses 3DGS for physical interaction
and direct manipulation [Jiang et al. 2024; Modi et al. 2024; Xie et al.
2023; Zhao et al. 2024], or allows sophisticated editing [Chen et al.
2024a; Liu et al. 2024a]. However, a prerequisite for most applica-
tions of this kind is segmenting individual objects or parts from the
3DGS scene, where existing methods fall short in flexibility.
2.2
Segmenting 3D Gaussian Splats
A wide range of works address segmentation of 3DGS scenes, with
the most notable tabulated in Tb.1. Many prior methods devise per-
scene learning techniques (Tb.1, per-scene training) to counter mask
inconsistencies of 2D segmentation networks like SAM [Kirillov
et al. 2023], resulting in per-Gaussian feature vectors. Feature3DGS
[Zhou et al. 2024] distill general 2D features, not focusing specifi-
cally on segmentation, while other approaches of this class typically
use SAM or another 2D segmentation network. GaussianGrouping
[Ye et al. 2025] propagates IDs using off-the-shelf tracker [Cheng
et al. 2023], and imposes regularization losses. ClickGaussian [Choi
et al. 2025], GARField [Kim et al. 2024], SAGA [Cen et al. 2023],
SegWild [Bao et al. 2025] and OmniSeg3D [Ying et al. 2024] all
perform scale-aware or hierarchical contrastive learning to ensure
multi-view feature consistency, while EgoLifter’s [Gu et al. 2025]
contrastive learning takes special care of dynamic objects. These
approaches are effective at generating a pre-processed version of the
scene that could be used for semantic reasoning and once trained
allow segmenting out 3D Gaussians based on queries such as fea-
ture proximity to one or several points. Beyond the time-consuming
scene pre-processing, which takes tens of minutes to hours, depend-
ing on the method, this class of techniques is inherently limited in
their flexibility. While these approaches implement slightly differ-
ent interfaces and strategies for converting features to 3D masks,
Method
Features
Seg.
training
time
ClickGaussian
[Choi et al. 2025]
yes
10 ms
OmniSeg3D
[Ying et al. 2024]
yes
not reported
GARField
[Kim et al. 2024]
yes (bndl)
320ms / lvl
Gau-Grouping
[Ye et al. 2025]
yes (bndl)
1.2s
EgoLifter
[Gu et al. 2025]
yes (bndl)
not reported
Feature3DGS
[Zhou et al. 2024]
yes
not reported
FlashSplat
[Shen et al. 2025]
no
30s
GaussianEditor
[Chen et al. 2024a]
no
40s
iSegMan
[Zhao et al. 2025]
yes
4-6s
Seg-Wild
[Bao et al. 2025]
yes
not reported
pre-prints
SAGA
[Cen et al. 2023]
yes
4ms
CoSSeg
[Dou et al. 2024]
yes
not reported
GaussianCut
[Jain et al. 2024]
no
50-120s
Ours
no
1-5s
Table 1. 3D Segmentation methods for 3D Gaussian Splats, prioritizing
methods that take some form of user input. Many approaches require
Features training or extraction for every input scene, where in some cases
this step is bundled into original 3DGS training (noted as "(bndl)"). When
reported, segmentation time is listed, given user input such as a target click.

<!-- page 3 -->
ArtisanGS: Interactive Tools for Gaussian Splat Selection
with AI and Human in the Loop
•
3
(a) Controlled setting
(b) Realistic setting
Fig. 2. 3D Capture Setups: While segmenting objects from controlled
captures, like the toy suspended by wires (a), is relatively simple with existing
tools, these solutions fall short on more realistic use cases (b).
mistakes, noise and biases are inevitably pre-baked into the feature
field. It is impossible for the user to deviate from the types of masks
used for pre-training or to correct mistakes beyond adding addi-
tional target feature vectors. Many of the same limitations apply to
RT-GS2 [Jurca et al. 2024], the only generalizable technique involv-
ing semantic feature learning, which trains a set of networks on a
small dataset of scenes, but it is not clear if this work can generalize
beyond indoor environments, and only 2D novel view segmentation
results are presented.
The approaches that generate 3D segmentation without special
pre-training are more similar to our method. Like ours, most be-
gin with a user-provided 2D mask, typically generated with a pre-
trained network like SAM. Several methods require initial user clicks,
project these clicks onto 3D Gaussians and track these 3D points
[Chen et al. 2024a; Hu et al. 2024a; Shen et al. 2025] or epipolar
line [Zhao et al. 2025] to generate SAM queries for other views, an
approach that can break down for far away views and is too tied to
click-based input, making it impossible to e.g. manually annotate
a mask. GaussianCut [Jain et al. 2024] is the only one leveraging a
video mask tracking network to propagate a single 2D mask to other
views, but it likewise does not offer strategies to correct mistakes.
We instead choose to use Cutie [Cheng et al. 2024] for mask tracking,
which due to the unique design of its memory frames, makes our
interactive segmentation amenable to user correction. Once a 2D
mask is extended to multi-view masks, these are aggregated to 3D
Gaussian labels. GaussianEditor [Chen et al. 2024a], SAGD [Hu et al.
2024a] (previously SAGS [Hu et al. 2024b]), iSegMan [Zhao et al.
2025] and [Joseph et al. 2024] devise voting schemes for assigning
per-Gaussian labels, while FlashSplat formulates the segmentation
as an integer linear programming optimization [Shen et al. 2025] and
GaussianCut [Jain et al. 2024] a graph cut problem. Our solution is
faster than most others (See Tb.1) and easier to extend to alternative
3DGS formulations, because we treat differentiable splat renderer
as a black box component. Given limited available benchmarks, our
approach offers comparative quality to other others and, unlike
prior methods, allows users many strategies to correct mistakes in
the initial segmentation. In addition, we discuss emerging software
tools in the Supplemental Material and our video.
2.3
Editing Applications on Splats
Several approaches touch on interactive, prompt-based or style-
driven editing of 3DGS scenes [Chen et al. 2024a; Jiang et al. 2024;
Liu et al. 2024b; Palandra et al. 2024; Vachha and Haque 2024; Wu
et al. 2025; Yi et al. 2024], but in most cases allowing users targeted
control over the modified area is at best an afterthought. We show
that the flexible selection and segmentation tools in ArtisanGS can
enable more controllable editing applications for 3DGS. Similarly,
works targeting inpainting of 3D captured scenes [Barda et al. 2024;
Chen et al. 2024b; Lu et al. 2024; Weber et al. 2024] focus on remov-
ing or hallucinating entire objects, typically assuming that the mask
or target area is given. Lack of appropriate tools makes these tech-
niques difficult to test on in-the-wild scenes, where targeted masks
are difficult to obtain. Our goal is to enable this line of research to
address more targeted editing and completion of 3DGS scenes, to
enable crafting interactive applications from in-the-wild captures.
As an illustration, we develop a prototype editing application by
building on work in controllable video diffusion models [Hong et al.
2022; Xu et al. 2024; Yang et al. 2024].
3
Preliminaries
3.1
Motivation
Multi-view captures like NERFs and 3D Gaussian Splats (3DGS)
have fascinated practitioners with their ability to effortlessly re-
construct highly realistic 3D environments. However, for practical
applications, these environments remained largely static, confined
to novel view synthesis. Recent advances offering practical solutions
for dynamic effects on 3DGS scenes, including physics simulation
[Modi et al. 2024; Xie et al. 2023] and relighting [Gao et al. 2025],
are promising to bring 3DGS into dynamic applications. While indi-
vidual high-quality 3DGS objects can be reconstructed from highly
controlled capture setups (e.g. suspended by wires in Fig.2a), this se-
verely limits ability to capture more realistic scenes (Fig.2b) or work
with videos and splat models available online. Extracting usable
objects from such in-the-wild 3DGS scenes is prohibitively difficult
with the current state of tools, a gap that we address in this work.
3.2
Method Overview
Imagine working with a monolithic capture of a cluttered environ-
ment, like a play room. To construct an interactive environment,
this scene must first be broken apart into individual objects. This
is the core task addressed by our method in §4, showing why fully
automatic solutions do not work perfectly, and how the user could
more directly control the final output. Flexible selection forms the
necessary backbone for many applications.
Once segmented, the object or a scene might have arbitrary ori-
entation, making everything, starting with camera control, more
challenging. Occlusions within the scene will also inevitably cause
parts of the captured objects to be missing. Unless perfectly chore-
ographed, source views will also contain varying level of detail for
different view angles, resulting in areas of degraded quality around
the object, which may need local targeted editing and refinement. In
§6, we show how our selection and segmentation tools can feed into
such applications for 3DGS object processing, including orientation
§6.1 and an early prototype of local editing §6.2.
The clean and consistent design of 2D and 3D selection in our
toolkit combines automatic AI-driven techniques with user input
and could be integrated into future end-user applications for crafting

<!-- page 4 -->
4
•
Clement Fuji Tsang, Anita Hu, Or Perel, Carsten Kolve, and Maria Shugrina
Fig. 3. Auto-Tracked Segmentation with Corrections: We propose automatic way to project 2D user masks 𝑆⊞
𝑖to 3D selection 𝑆 over 3D Gaussians,
while allowing users to correct the outcome (§4.4). Left: notation and selection modes supported in our design (§4).
interactive 3DGS scenes. As a sample application, we show physics
simulation with Simplicits [Modi et al. 2024] on scenes processed
with our technique (§6.3).
3.3
Definitions
We start with a pre-trained 3DGS scene [Kerbl et al. 2023], contain-
ing a set G of 𝑛individual 3D Gaussians 𝐺𝑖, each with a position
𝝁𝑖, covariance Σ𝑖, view-dependent color and opacity 𝛼𝑖. We assume
the existence of optimized differentiable rendering kernels for G, in-
cluding render(G, 𝑣) producing RGBA rendering of the 3DGS scene
from camera view 𝑣, depth(G, 𝑣) producing camera-space depth ren-
dered from 𝑣, features(G, 𝑣, 𝐹) rendering any custom per-Gaussian
feature vectors 𝐹:= {𝐹0...𝐹𝑛}, viz(G, 𝑣) producing a binary mask
specifying the Gaussians visible from 𝑣and first_hits(G, 𝑣) out-
putting the id of the first hit Gaussian per pixel. Our method does
not assume anything beyond the existence of these functions and
so is in principle applicable to alternative 3DGS variants such as
[Huang et al. 2024; Moenne-Loccoz et al. 2024], but we have run
all our experiments on the original formulation [Kerbl et al. 2023],
trivial to extend to depth(G, 𝑣) and features(G, 𝑣, 𝐹) by applying
the original render(G, 𝑣) function to other per-Gaussian features.
Typically, G has high-quality appearance from camera views that
do not stray too far from the training views ¯𝑉:= {¯𝑣0...¯𝑣𝑛} used for
optimization, but may appear foggy or abstract from views that are
not well-represented (Fig.1), which can affect the result of AI models
trained on real images. While we do not assume the knowledge of
¯𝑉, our algorithm has the option of using them if available.
4
Interactive Segmentation
We will now present an interactive toolkit for 3DGS selection and
segmentation. We define the segmentation problem as selecting
a subset of Gaussians S ∈G according to the user intent. Any
implementation of our proposed toolkit will allow users control
of the camera view 𝑣𝑐and will keep track of the 2D segmentation
mask 𝑆⊞(active for 𝑣𝑐) and of the current 3D segmentation mask
𝑆, containing a binary value for every element of G. We will use S
to refer to the subset of Gaussians currently in 𝑆. Different color
is used to denote 2D and 3D selections in our diagrams and in our
UI to make them easier to distinguish (See Fig.3).
Given preliminary requirements (§4.1, §4.2), we propose combin-
ing multiple ways to project 2D masks to 𝑆. First, we show simple
(a) Frustum projection
(b) Depth projection
Fig. 4. Manual Projection(§4.3) of 2D masks 𝑆⊞
𝑖to 3D, combined with
different selection modes (§4.1), allow flexible manual selection.
yet powerful manual projection modes (§4.3), and then detail our
automatic mask tracking and segmentation method in §4.4.
4.1
Selection Modes
Established image selection tools in software like Photoshop support
the following major modes: new (N) - replace current selection, add
to (A), subtract from (S) and intersect with (I) the current selection.
To provide consistent experience, we support all of these modes
both for 2D selection and 3D selection (Fig.3, left). In both cases,
the modes correspond to boolean operations on the active image
mask 𝑆⊞or binary per-Gaussian mask 𝑆. In our implementation,
N is the default mode, and others are activated through Ctrl, Alt
and Shift modifiers, but many other UI designs are possible.
4.2
Required 2D Mask Capabilities
Because users can only see a 2D rendering of 𝐺, 2D selection is a
necessary prerequisite for any 3D selection interface. While any
2D image segmentation techniques could be used in combination
with our toolkit, it is critical to allow users a variety of 2D masking
tools to bootstrap interactive 3D segmentation below. Our particular
implementation, like others before it, allows users to generate a mask
𝑆⊞for any view 𝑣𝑐from one or more positive and negative clicks
using SAM [Kirillov et al. 2023], but other models could be used
instead. We also allow manually painting 2D areas and drawing 2D
bounding boxes, while supporting the selection modes in §4.1.

<!-- page 5 -->
ArtisanGS: Interactive Tools for Gaussian Splat Selection
with AI and Human in the Loop
•
5
4.3
Manual 2D to 3D Projection Modes
In addition to automatic aggregation (§4.4 to follow), our design
supports two manual modes of projecting user’s 2D selection to
3D. The frustum projection mode selects all Gaussians, for which
the mean projects into the current mask 𝑆⊞
𝑐of the current view 𝑣𝑐.
This effectively selects all the Gaussians falling into the sweep of 𝑆⊞
𝑐
through the camera frustum. Coupled with the selection modes in
§4.1, frustum projection is surprisingly effective for some use cases.
In Fig.4a, projection of 𝑆⊞
0 followed by projection of 𝑆⊞
1 with mode
I (intersect), effectively selects the facade of the gingerbread house.
In some cases, selecting surface layer is more desirable. In the
depth projection mode, we select all the Gaussians that are in the
frustum projection of 𝑆⊞and also lie within a threshold of the ren-
dered depth at their location. This mode allows picking up surface
detail, such as the wreath in Fig.4b.
4.4
Auto-Tracked Segmentation with Corrections
We propose a fast automatic way to convert one or more user-
provided 2D masks 𝑆⊞
0 ...𝑆⊞
𝑘corresponding to views 𝑣0...𝑣𝑘to a 3D
Gaussian mask 𝑆 (Fig.3). Like other training-free approaches for
this task [Chen et al. 2024a; Hu et al. 2024a; Jain et al. 2024; Shen
et al. 2025], we generate multi-view masks (§4.4.2) for a dense set of
views (§4.4.1) and then aggregate these masks into a 3D mask (§4.4.3).
Uniquely, our approach allows users visibility into the method and
ability to correct mistakes (§4.4.4).
4.4.1
Selecting Dense Views. We support multiple ways to sample
dense views around the target object. If the training views ¯𝑉are
available, all or a subset can be used. Training views are guaranteed
to show the scene from a well-optimized angle, but may be very
zoomed out for large scenes. In addition, requiring training views
would also constrain the types of captures that could be segmented.
Therefore, we devise an alternative method, using the point cloud
obtained by lifting first_hits(G, 𝑣0 from the masked area 𝑆⊞
0 . We
turn the camera around the center of this point cloud, doing a full
circle trajectory on the plane defined by the camera up axis, and
use the corresponding user view 𝑣0 for up direction and distance
from the look at point. We ablate the choice of training or camera
turnaround views in our results section. Note that the number of
views used for tracking (𝑚), is an important hyperparameter for our
method’s speed, but we found it to work robustly when sampling
about 50 views (See §5.3).
4.4.2
Obtaining Multi-View Masks. Similarly to ours, many training-
free prior methods tackling 3DGS segmentation start with a mask
𝑆⊞
0 and then use it to obtain 𝑚multi-view masks 𝑆⊡
0 ...𝑆⊡
𝑚for the
dense views ¤𝑣0...¤𝑣𝑚. Most of these techniques [Chen et al. 2024a;
Hu et al. 2024a; Shen et al. 2025] track depth-projected query points
from the first mask to generate SAM queries for other views. This
approach can cause errors for more extreme views where 3D query
points are not visible and leaves the result at the mercy of a specific
click-based network like SAM [Kirillov et al. 2023]. In contrast, we
rely on a robust mask tracking network Cutie [Cheng et al. 2024].
This design decision results in more robust tracking, and supports
our goal of allowing users to add more guidance when needed.
The network architecture and inference pipeline of Cutie accepts
object-level conditioning through one or more reference frames,
injected at appropriate points in the video sequence due to memory
constraints (See user masks 𝑆⊞
𝑖in Fig.3C). To facilitate attending
to appropriate annotations, we shift the target turnaround views
¤𝑣0...¤𝑣𝑚to begin with the optimal view angle, obtaining shifted se-
quence ˆ𝑣0...ˆ𝑣𝑚(Fig.3B). We select the first view ˆ𝑣0 to be ¤𝑉∗(𝑣0),
defined as the target view ¤𝑣𝑖that is most similar to the annotated
view 𝑣0 according to the following criterion:
¤𝑉∗(𝑣) := argmin
¤𝑣𝑗
𝐽(viz(G, 𝑣), viz(G, ¤𝑣𝑗)
(1)
where viz is the visibility mask defined in §3.3, and 𝐽is the Jaccard
index. Thus, Cutie is injected with the user mask 𝑆⊞
0 and corre-
sponding render(G, 𝑣0) right before predicting the mask for the
most similar view ˆ𝑣0. Given multiple user masks 𝑆⊞
𝑖for the views 𝑣𝑖,
each 𝑆⊞
𝑖and render(G, 𝑣𝑖) is injected as a memory frame prior to
predicting the corresponding most similar target view ¤𝑉∗(𝑣𝑖). This
approach allows users to annotate any number of frames for any
view angle, without being constrained to pre-selected views.
4.4.3
Aggregating to 3D. Given user masks 𝑆⊞
0 ...𝑆⊞
𝑘for views 𝑣0...𝑣𝑘,
and automatically tracked masks 𝑆⊡
0 ...𝑆⊡
𝑚for dense views ¤𝑣0...¤𝑣𝑚,
we now aggregate them into a binary mask 𝑆 over the Gaussians
(Fig.3D). Instead of devising a custom voting scheme like [Chen
et al. 2024a; Hu et al. 2024a] specific to a particular 3DGS variant,
or formulating a linear programming [Shen et al. 2025] or graph
cut problem [Jain et al. 2024], which has additional complexity and
overhead, we simply leverage the fast differentiable 3DGS renderer
to optimize the mask assignment. Specifically, we run a single loop
over the views ¤𝑣0...¤𝑣𝑚, 𝑣0...𝑣𝑘, optimizing a one channel feature 𝑀
for each Gaussian with an L2 image loss between the 2D masks and
features(G, 𝑣, 𝑀). We found it effective to simply set the binary
𝑆 to 𝑀> 0.5, a setting we use for all demos and experiments.
The "black-box" treatment of 3DGS renderer makes this aggregation
applicable to other point splatting formulations like [Huang et al.
2024; Moenne-Loccoz et al. 2024].
4.4.4
User Corrections. Crucially, unlike prior methods, we also
allow users to diagnose the cause of error in the 3d aggregation.
Using our UI, users can browse automatic masks generated by Cutie
and add more masks for any additional view via SAM annotation or
manual mask painting. The annotated views are inserted into the
Cutie inference based on their proximity with the target views for
which automatic masks are being generated (§4.4.2), resulting in a
more robust turnaround performance and better aggregation.
4.4.5
Performance Improvements. The performance of any method
leveraging 2D masks for 3D aggregation is sensitive to occlusions
around the object. To improve performance of our method in clut-
tered scenes, we give users the option to mark a mask as containing
no occlusions. When such masks are provided (default setting), we
first pre-segment the scene using intersecting frustum projections
(§4.3) of these masks and perform tracking (§4.4.2) and aggregation
(§4.4.3) only on this segment. This optimization not only improves
robustness to occlusions, but also the speed of the aggregation due
to faster rendering.

<!-- page 6 -->
6
•
Clement Fuji Tsang, Anita Hu, Or Perel, Carsten Kolve, and Maria Shugrina
5
Results and Evaluation
In this section, we evaluate our auto-tracked segmentation (§4.4)
quantitatively (§5.1), show qualitative comparisons with related
selection and segmentation tools (§5.2) and present ablations (§5.3)
See the following section §6 for applications.
(a) NVOS scribbles vs. our alternative SAM queries.
(b) NVOS occl.
(c) Large inaccuracies in automatic masks of LERF-mask
Fig. 5. Evaluation Datasets: Annotations on both NVOS (a) and LERF-
Mask (b) have inaccuracies. We suggest alternative inputs for NVOS (a)
5.1
Quantitative Evaluation
5.1.1
Baselines. We compare our segmentation against FlashSplat[Shen
et al. 2025] and GaussianCut[Jain et al. 2024], which, similarly to our
method, require no pre-processing of the input scene (See segmen-
tation methods in Tb.1). In addition, we compare against SAGA[Cen
et al. 2023], GaussianGrouping [Ye et al. 2025], iSegMan[Zhao et al.
2025] and OmniSeg3D[Ying et al. 2024], competitive methods that
need scene pre-processing in order to allow segmentation. Note that
our method was developed in 2024 and we may be missing some
more recent techniques in this evaluation.
5.1.2
Datasets and Metrics. There is no robust and diverse bench-
mark for the segmentation task that we target. Commonly used
NVOS [Ren et al. 2022] dataset is very small, and LERF-Mask [Ye
et al. 2025] contains noisy auto-labels (e.g. see noisy auto-labels in
Fig.5c). Because most baselines use this dataset, we report results on
the smaller, more accurate NVOS dataset [Ren et al. 2022], consist-
ing of a small number of front-facing scenes from LLFF [Mildenhall
et al. 2019] with target scribbles in one frame and a single ground
truth mask for another frame. The input scribbles in NVOS are an
imperfect representation of user intent, and fail with modern seg-
mentation methods that rely on clicks, such as SAM [Kirillov et al.
2023] (See Fig.5, where scribbles are not placed on all the target
flowers, confusing SAM). While many of the baselines we compare
with also rely on input clicks, the codebases and papers of Flash-
Splat[Shen et al. 2025], SAGA[Cen et al. 2023], GaussianCut[Jain
et al. 2024] and OmniSeg3D[Ying et al. 2024] do not include the
exact logic for sampling points from NVOS scribbles or the number
of points. However, these details have a pronounced effect on click-
based methods, like SAM, and make reported numbers from these
related works that are using random sampling from the scribbles
Method
mIoU↑
Acc↑
FlashSplat
91.8
98.6
GaussianCut
92.5
98.4
Gaussian Grouping
90.6
98.2
SAGA
90.9
98.3
iSegMan
92.0
98.4
OmniSeg3D
91.7
98.4
OmniSeg3D (with our points)
78.5
96.4
Ours (with pre-segment)
82.4
98.1
Ours (without pre-segment)
94.1
98.8
Table 2. Segmentation Eval on NVOS.
unreliable. 1 Nonetheless, we include a comparison for complete-
ness, and report click sampling logic here. Because our method
starts with a user-annotated mask, failing due to bad SAM initial-
ization would not meaningfully evaluate our method. Instead of
NVOS scribbles, we provide a small number (1 to 6) of positive point
inputs for the starting frame, and use the same ground truth frame
to evaluate. For all baselines, we report original NVOS results, with
point click logic tuned for their method, and for OmniSeg3D [Ying
et al. 2024], the best available method with a released codebase,
we additionally show performance on our input point clicks. We
use standard metrics of pixel classification accuracy (Acc) and fore-
ground intersection-over-union (IoU). At best, NVOS provides a
very noisy estimate of performance due to its tiny size and carefully
choreographed front-facing scenes, but we include it as the stan-
dard benchmark reported in literature, and later focus on qualitative
differences that make our method easy to apply in practice (§5.2).
5.1.3
Results. Results in Tb.2, showing competitive performance of
our method against baselines, while also being faster, and requiring
no scene pre-processing (See Tb.1 for prior method properties and
speed). Because point sampling results in noisy results (see above),
we did not reevaluate the baselines under the slightly different
setting of click inputs rather than scribbles. However, for the com-
petitive OmniSeg3D, our point samples result in severely degraded
performance, suggesting that their technique requires a lot more
points to work accurately, and suggesting that custom point sam-
pling logic of prior works is likely designed to their advantage. In
all cases, our technique outperforms others when pre-segmentation
(§4.4.5 is turned off, and degraded performance is due to a single
example ("horns left") where the annotated frame does not include
the whole target object (Fig.5b). In practice, when using our method,
users have a choice to enable the pre-segmentation optimization. We
next provide qualitative evaluation, showing that our technique may
be easier to apply in practice, allowing user-driven segmentation
with corrections.
5.2
Qualitative Results
Qualitatively, we compare our method against one pre-training
method [Kim et al. 2024] and the training-free GaussianEditor [Chen
et al. 2024a] approach. We use in-the-wild captured scenes or chal-
lenging 360-degree scenes from LERF [Kerr et al. 2023] that are
1To quantify the effect of point sampling, we ran SAM segmentation on one of the
NVOS images 20 times, using randomized 3 to 10 positive and 1 to 4 negative clicks.
The resulting masks have an average pairwise IoU of 68.3%, and it can be as small as
3.5% between runs, showing the overwhelming effect of point choices on performance.

<!-- page 7 -->
ArtisanGS: Interactive Tools for Gaussian Splat Selection
with AI and Human in the Loop
•
7
closer to our target use case. While in the paper, GaussianEditor
reports better performance, we found its segmentation running in
around 40s on a higher-end GPU, making any sort of interaction or
iteration difficult. Unlike GaussianEditor in practice, our method
runs in 1-5 seconds on the same hardware, enabling interactive
iteration over the target segmentation and user inputs. Critically,
we also allow users to correct both automatic masks or perform seg-
mentation manually (§4.3). We also observe more frequent mistakes
for similar examples in Fig.8d. As described in the related work,
Garfield [Kim et al. 2024] suffers from features that are pre-baked
during training and can make finer-grained segmentation difficult.
On the LERF figurines scene, Garfiled shows similar performance on
simple objects, but for more complex examples like "Charlie" in the
Twizzlers box or the camera with the strap, Garfield’s discrete Group
Level parameter is insufficient to select the target object and its thin
parts (Fig.8f), while our automatic tracking with a single reference
easily selects these. We also made an effort to run FlashSplat [Shen
et al. 2025], but ran into technical issues not addressed by the au-
thors (URL). Comparing to manual segmentation with software tool
SuperSplat [PlayCanvas 2024] (Fig.8e), we found SuperSplat very
difficult and time-consuming to use, especially when separating
objects from surfaces and dealing with stacked objects. On the other
hand, our method is a lot faster and user-friendly, providing a good
initial segmentation using SAM selection, and allowing additional
manual fine-tuning only if necessary. We believe that it strikes just
the right balance between automation and user intervention, allow-
ing selecting virtually any desirable subset of Gaussians given user
intent. See §6 for possible applications of such segmentation, and
Supplemental Video (soon to be uploaded) for additional qualitative
results.
5.3
Ablations
For ablations, we used LERF [Kerr et al. 2023] figurines scene, a
challenging 360-degree scene. Because the automatic mask anno-
tations in LERF-Mask [Ye et al. 2025] are very noisy (Fig.5c), we
instead hand annotated the pretrained 3DGS scene without using
any automatic segmentation, using only manual 2D bounding box
selections with the frustum projection described in (§4.3). For each
object, we additionally annotate input SAM queries and the cor-
responding mask for one training view (input view: train) and for
one additional view outside of the training view trajectory (input
view: user), to test different settings of our algorithm. We call this
dataset Figurines3DSeg. Unlike quantitative results, computing 2D
mask metrics for Acc and mIoU, we use metrics computed over ac-
tual Gaussians selected with our method agains ground truth hand
annotation.
Because our method tracks masks across viewes (§4), the choice
of views is important. We compare using original scene training
views against automatic dense views (§4.4.1) and the impact of
the number of views 𝑚on quality and speed of our method in
Tb3. We found 𝑚= 50 to be optimal for performance as well as
speed, completing full tracking (including Cutie inference) and 3D
segmentation in only 1.5-2.5s. While this is not real-time, this delay is
small enough to allow users to iterate with the algorithm in practice.
For completeness, we also test with two different kinds of view
input view
train
user
mIoU↑Acc↑mIoU↑Acc↑Speed (s)
type of views (num.)
training (all)
94.0
99.2
88.9
98.9
9-12s
training (100)
93.9
99.2
93.3
99.1
3-4s
training (50)
93.9
99.1
94.3
99.2
1.5-2.5s
training (20)
92.8
99.0
94.0
99.2
0.6-1.2s
training (10)
89.1
98.6
93.3
99.0
0.3-1s
auto turnaround (100)
93.8
98.9
93.2
99.0
3-4.5s
auto turnaround (50)
93.5
98.9
93.3
99.0
1.5-2.5s
auto turnaround (20)
90.6
98.5
93.3
99.0
0.6-1.2s
auto turnaround (10)
89.3
98.0
92.1
98.8
0.3-1s
no pre-segmentation
training (all)
83.88
98.4
76.9
97.8
26-27s
auto turnaround (100)
89.0
98.2
90.7
98.6
8-9s
Table 3. Segmentation Ablations on hand-labeled Figurines 3DGS scene.
Fig. 6. Impact of presegmentation on the inputs to the tracker. Top: Input
without presegmentation. Bottom: Input with presegmentation.
annotations, showing that our method generalizes to user-selected
annotated views, making the interaction a lot less constrained. While
we see some degradation when user-selected views are used, the
usability still makes this feature attractive. In addition, we see a
degradation in both speed and quality of the output when the pre-
segmentation (§4.4.5 is turned off. This is because in the scenes
with many objects, the tracked views may have occlusions. Pre-
segmentation effectively removes some of the occluders in these
views (See Fig.6).
6
Applications
Our selection and segmentation toolkit feeds into many downstream
applications for 3DGS.
6.1
Interactive Orientation
Orienting a scene is important for consistent camera manipulation,
and is critical for physics simulation, now possible directly on the
3DGS [Modi et al. 2024]. We observed that in most cases, the desir-
able XYZ axes coincide with the principal directions of variation
for objects or surfaces. Our auto-orientation module allows users
to automatically align the PCA basis computed over the means of
the selected Gaussians with a chosen permutation of world axes.
For example, the user could apply frustum projection to select a flat
surface (Fig.9a1-3), then align Z axis with the axis of least variation
(resulting in top capera view in Fig.9a 4) to achieve a consistent
gravity direction. Manually orienting a scene is challenging, and we
found this technique simple and effective when used in conjunction
with our selection tools (§4).

<!-- page 8 -->
8
•
Clement Fuji Tsang, Anita Hu, Or Perel, Carsten Kolve, and Maria Shugrina
Fig. 7. Object completion(§6.2): after the user marks region to be com-
pleted and iterates on a 2D inpainting for one view, we apply a custom video
inpainting model to propagate the result to multi-view consistent frames,
which are used to fine-tune the 3DGS object.
6.2
User-Guided Editing
Unlike much of generative AI research, our objective is not to hal-
lucinate large unseen areas. Instead, our method empowers future
directions for targeted editing. This targeting is enabled through
the various selection modes of our tool, providing different levels
of precision. E.g. to indicate missing areas occluded parts during
capture, the user can select the Gaussians around the hole using the
paint tool. This selection could be used to generate masks for AI
inpainting and be used to add new Gaussians. For editing existing
areas, SAM selection can be used to efficiently remove parts. The
paint tool can also be used to draw on interesting shapes to inpaint.
As a prototype towards targeted local editing, we experiment with
a Video inpainting network that can be used to inpaint and optimize
Gaussians only in the user-selected regions. We build our method
on CogVideoX’s Image-to-Video model [Yang et al. 2024] as a strong
video generation foundation and insert CamCo’s epipolar attention
module [Xu et al. 2024] for camera control and 3D consistency. The
inputs to our video model are masked video frames, binary masks
for each frame, plucker embeddings and epipolar lines from camera
parameters. The first frame of the video is a reference image that is
generated by Stable Diffusion XL inpainting model. The typical user
workflow would be to inpaint the first view using a text prompt,
once satisfied, apply our video model to generate additional views
starting from the first view. To propagate these changes to 3D, we
remove the Gaussians that are selected and initialize new gaussians
randomly inside the selection bounding box then train using the
inpainted views. We show these early experiments to demonstrate
how precise selection can help guide editing. Because we do not
train on the unselected original Gaussians, we do not modify the
look of the unselected area. We are excited to explore this application
in future research.
6.3
Simulating Splat Objects
With the ability to segment, orient (§6.1) and refine (§6.2) it is be-
coming increasingly feasible to convert raw in-the-wild captures to
simulated scenes. For example, 3DGS objects can be directly simu-
lated using Simplicits [Modi et al. 2024] (See Fig.9b and video). Our
flexible selection and segmentation toolkit also makes it possible
for users to select individual object parts and assign different ma-
terials, for example to make the hair of the doll more deformable.
This application is now directly possible using existing simulation
techniques and our user-guded selection.
7
Conclusion
In conclusion, we presented ArtisanGS, a suite of versatile interac-
tive selection and segmentation tools for 3D Gaussian Splats with
AI and user in the loop. We believe that a flexible solution to user
guided segmentation is a necessary foothold for many applications.
References
Yongtang Bao, Chengjie Tang, Yuze Wang, and Haojie Li. 2025. Seg-Wild: Interactive
Segmentation based on 3D Gaussian Splatting for Unconstrained Image Collections.
In Proceedings of the 33rd ACM International Conference on Multimedia (Dublin,
Ireland) (MM ’25). Association for Computing Machinery, New York, NY, USA,
8567–8576. https://doi.org/10.1145/3746027.3755567
Amir Barda, Matheus Gadelha, Vladimir G. Kim, Noam Aigerman, Amit H. Bermano,
and Thibault Groueix. 2024. Instant3dit: Multiview Inpainting for Fast Editing of
3D Objects. arXiv:2412.00518 [cs.CV] https://arxiv.org/abs/2412.00518
Jiazhong Cen, Jiemin Fang, Chen Yang, Lingxi Xie, Xiaopeng Zhang, Wei Shen, and Qi
Tian. 2023. Segment Any 3D Gaussians. arXiv preprint arXiv:2312.00860 (2023).
Honghua Chen, Chen Change Loy, and Xingang Pan. 2024b. MVIP-NeRF: Multi-view
3D Inpainting on NeRF Scenes via Diffusion Prior. In Proceedings of the IEEE/CVF
Conference on Computer Vision and Pattern Recognition. 5344–5353.
Yiwen Chen, Zilong Chen, Chi Zhang, Feng Wang, Xiaofeng Yang, Yikai Wang, Zhon-
gang Cai, Lei Yang, Huaping Liu, and Guosheng Lin. 2024a. Gaussianeditor: Swift
and controllable 3d editing with gaussian splatting. In Proceedings of the IEEE/CVF
conference on computer vision and pattern recognition. 21476–21485.
Ho Kei Cheng, Seoung Wug Oh, Brian Price, Joon-Young Lee, and Alexander Schwing.
2024. Putting the object back into video object segmentation. In Proceedings of the
IEEE/CVF Conference on Computer Vision and Pattern Recognition. 3151–3161.
Ho Kei Cheng, Seoung Wug Oh, Brian Price, Alexander Schwing, and Joon-Young Lee.
2023. Tracking anything with decoupled video segmentation. In Proceedings of the
IEEE/CVF International Conference on Computer Vision. 1316–1326.
Seokhun Choi, Hyeonseop Song, Jaechul Kim, Taehyeong Kim, and Hoseok Do. 2025.
Click-gaussian: Interactive segmentation to any 3d gaussians. In European Conference
on Computer Vision. Springer, 289–305.
Bin Dou, Tianyu Zhang, Yongjia Ma, Zhaohui Wang, and Zejian Yuan. 2024. Cosseg-
gaussians: Compact and swift scene segmenting 3d gaussians.
arXiv preprint
arXiv:2401.05925 (2024).
Kang Du, Zhihao Liang, and Zeyu Wang. 2024. GS-ID: Illumination Decomposition on
Gaussian Splatting via Diffusion Prior and Parametric Light Source Optimization.
arXiv preprint arXiv:2408.08524 (2024).
Sara Fridovich-Keil, Alex Yu, Matthew Tancik, Qinhong Chen, Benjamin Recht, and
Angjoo Kanazawa. 2022. Plenoxels: Radiance fields without neural networks. In
Proceedings of the IEEE/CVF conference on computer vision and pattern recognition.
5501–5510.
Jian Gao, Chun Gu, Youtian Lin, Zhihao Li, Hao Zhu, Xun Cao, Li Zhang, and Yao
Yao. 2025. Relightable 3d gaussians: Realistic point cloud relighting with brdf
decomposition and ray tracing. In European Conference on Computer Vision. Springer,
73–89.
Qiao Gu, Zhaoyang Lv, Duncan Frost, Simon Green, Julian Straub, and Chris Sweeney.
2025. Egolifter: Open-world 3d segmentation for egocentric perception. In European
Conference on Computer Vision. Springer, 382–400.
Wenyi Hong, Ming Ding, Wendi Zheng, Xinghan Liu, and Jie Tang. 2022. CogVideo:
Large-scale Pretraining for Text-to-Video Generation via Transformers. arXiv
preprint arXiv:2205.15868 (2022).
Xu Hu, Yuxi Wang, Lue Fan, Junsong Fan, Junran Peng, Zhen Lei, Qing Li, and
Zhaoxiang Zhang. 2024a. SAGD: Boundary-Enhanced Segment Anything in 3D
Gaussian via Gaussian Decomposition (or: Segment Anything in 3D Gaussians).
arXiv:2401.17857 [cs.CV] https://arxiv.org/abs/2401.17857
Xu Hu, Yuxi Wang, Lue Fan, Junsong Fan, Junran Peng, Zhen Lei, Qing Li, and Zhaoxiang
Zhang. 2024b. Semantic anything in 3d gaussians. arXiv preprint arXiv:2401.17857
(2024).
Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger, and Shenghua Gao. 2024. 2d
gaussian splatting for geometrically accurate radiance fields. In ACM SIGGRAPH
2024 Conference Papers. 1–11.
Umangi Jain, Ashkan Mirzaei, and Igor Gilitschenski. 2024. GaussianCut: Interactive seg-
mentation via graph cut for 3D Gaussian Splatting. arXiv preprint arXiv:2411.07555
(2024).
Ying Jiang, Chang Yu, Tianyi Xie, Xuan Li, Yutao Feng, Huamin Wang, Minchen Li,
Henry Lau, Feng Gao, Yin Yang, et al. 2024. Vr-gs: A physical dynamics-aware
interactive gaussian splatting system in virtual reality. In ACM SIGGRAPH 2024
Conference Papers. 1–1.
Joji Joseph, Bharadwaj Amrutur, and Shalabh Bhatnagar. 2024. Gradient-Driven 3D
Segmentation and Affordance Transfer in Gaussian Splatting Using 2D Masks. arXiv
preprint arXiv:2409.11681 (2024). https://arxiv.org/abs/2409.11681

<!-- page 9 -->
ArtisanGS: Interactive Tools for Gaussian Splat Selection
with AI and Human in the Loop
•
9
Mihnea-Bogdan Jurca, Remco Royen, Ion Giosan, and Adrian Munteanu. 2024. RT-GS2:
Real-Time Generalizable Semantic Segmentation for 3D Gaussian Representations of
Radiance Fields. In 35th British Machine Vision Conference 2024, BMVC 2024, Glasgow,
UK, November 25-28, 2024. BMVA. https://papers.bmvc2024.org/0299.pdf
Bernhard Kerbl, Georgios Kopanas, Thomas Leimkühler, and George Drettakis. 2023.
3D Gaussian Splatting for Real-Time Radiance Field Rendering. ACM Transactions on
Graphics 42, 4 (July 2023). https://repo-sam.inria.fr/fungraph/3d-gaussian-splatting/
Justin Kerr, Chung Min Kim, Ken Goldberg, Angjoo Kanazawa, and Matthew Tancik.
2023. LERF: Language Embedded Radiance Fields. In International Conference on
Computer Vision (ICCV).
Chung Min Kim, Mingxuan Wu, Justin Kerr, Ken Goldberg, Matthew Tancik, and Angjoo
Kanazawa. 2024. Garfield: Group anything with radiance fields. In Proceedings of
the IEEE/CVF Conference on Computer Vision and Pattern Recognition. 21530–21539.
Alexander Kirillov, Eric Mintun, Nikhila Ravi, Hanzi Mao, Chloe Rolland, Laura
Gustafson, Tete Xiao, Spencer Whitehead, Alexander C Berg, Wan-Yen Lo, et al.
2023. Segment anything. In Proceedings of the IEEE/CVF International Conference on
Computer Vision. 4015–4026.
Zhihao Liang, Qi Zhang, Ying Feng, Ying Shan, and Kui Jia. 2024. Gs-ir: 3d gauss-
ian splatting for inverse rendering. In Proceedings of the IEEE/CVF Conference on
Computer Vision and Pattern Recognition. 21644–21653.
Kunhao Liu, Fangneng Zhan, Muyu Xu, Christian Theobalt, Ling Shao, and Shijian Lu.
2024a. Stylegaussian: Instant 3d style transfer with gaussian splatting. In SIGGRAPH
Asia 2024 Technical Communications. 1–4.
Kunhao Liu, Fangneng Zhan, Muyu Xu, Christian Theobalt, Ling Shao, and Shijian
Lu. 2024b. StyleGaussian: Instant 3D Style Transfer with Gaussian Splatting. In
SIGGRAPH Asia 2024 Technical Communications (SA ’24). Association for Computing
Machinery, New York, NY, USA, Article 21, 4 pages. https://doi.org/10.1145/3681758.
3698002
Yiren Lu, Jing Ma, and Yu Yin. 2024. View-consistent Object Removal in Radiance Fields.
In Proceedings of the 32nd ACM International Conference on Multimedia. 3597–3606.
Ben Mildenhall, Pratul P. Srinivasan, Rodrigo Ortiz-Cayon, Nima Khademi Kalantari,
Ravi Ramamoorthi, Ren Ng, and Abhishek Kar. 2019. Local Light Field Fusion:
Practical View Synthesis with Prescriptive Sampling Guidelines. ACM Transactions
on Graphics (TOG) (2019).
Ben Mildenhall, Pratul P Srinivasan, Matthew Tancik, Jonathan T Barron, Ravi Ra-
mamoorthi, and Ren Ng. 2021. Nerf: Representing scenes as neural radiance fields
for view synthesis. Commun. ACM 65, 1 (2021), 99–106.
Vismay Modi, Nicholas Sharp, Or Perel, Shinjiro Sueda, and David IW Levin. 2024.
Simplicits: Mesh-free, geometry-agnostic elastic simulation. ACM Transactions on
Graphics (TOG) 43, 4 (2024), 1–11.
Nicolas Moenne-Loccoz, Ashkan Mirzaei, Or Perel, Riccardo de Lutio, Janick Mar-
tinez Esturo, Gavriel State, Sanja Fidler, Nicholas Sharp, and Zan Gojcic. 2024. 3D
Gaussian Ray Tracing: Fast Tracing of Particle Scenes. ACM Transactions on Graphics
(TOG) 43, 6 (2024), 1–19.
Thomas Müller, Alex Evans, Christoph Schied, and Alexander Keller. 2022. Instant
Neural Graphics Primitives with a Multiresolution Hash Encoding. ACM Trans.
Graph. 41, 4, Article 102 (July 2022), 15 pages.
https://doi.org/10.1145/3528223.
3530127
Francesco Palandra, Andrea Sanchietti, Daniele Baieri, and Emanuele Rodolà. 2024.
GSEdit: Efficient Text-Guided Editing of 3D Objects via Gaussian Splatting. arXiv
preprint arXiv:2403.05154 (2024).
PlayCanvas. 2024. SuperSplat. https://playcanvas.com/supersplat
Zhongzheng Ren, Aseem Agarwala†, Bryan Russell†, Alexander G. Schwing†, and
Oliver Wang†. 2022. Neural Volumetric Object Selection. In IEEE/CVF Conference on
Computer Vision and Pattern Recognition (CVPR). († alphabetic ordering).
Victor Rong, Jingxiang Chen, Sherwin Bahmani, Kiriakos N Kutulakos, and David B
Lindell. 2024. GStex: Per-Primitive Texturing of 2D Gaussian Splatting for Decoupled
Appearance and Geometry Modeling. arXiv preprint arXiv:2409.12954 (2024).
Qiuhong Shen, Xingyi Yang, and Xinchao Wang. 2025. Flashsplat: 2d to 3d gaussian
splatting segmentation solved optimally. In European Conference on Computer Vision.
Springer, 456–472.
Cyrus Vachha and Ayaan Haque. 2024. Instruct-GS2GS: Editing 3D Gaussian Splats
with Instructions. https://instruct-gs2gs.github.io/
Zian Wang, Tianchang Shen, Merlin Nimier-David, Nicholas Sharp, Jun Gao, Alexander
Keller, Sanja Fidler, Thomas Müller, and Zan Gojcic. 2023. Adaptive shells for
efficient neural radiance field rendering. arXiv preprint arXiv:2311.10091 (2023).
Ethan Weber, Aleksander Holynski, Varun Jampani, Saurabh Saxena, Noah Snavely,
Abhishek Kar, and Angjoo Kanazawa. 2024. Nerfiller: Completing scenes via gener-
ative 3d inpainting. In Proceedings of the IEEE/CVF Conference on Computer Vision
and Pattern Recognition. 20731–20741.
Jing Wu, Jia-Wang Bian, Xinghui Li, Guangrun Wang, Ian Reid, Philip Torr, and Vic-
tor Adrian Prisacariu. 2025. Gaussctrl: Multi-view consistent text-driven 3d gaussian
splatting editing. In European Conference on Computer Vision. Springer, 55–71.
Tianyi Xie, Zeshun Zong, Yuxing Qiu, Xuan Li, Yutao Feng, Yin Yang, and Chenfanfu
Jiang. 2023. PhysGaussian: Physics-Integrated 3D Gaussians for Generative Dynam-
ics. arXiv preprint arXiv:2311.12198 (2023).
Dejia Xu, Weili Nie, Chao Liu, Sifei Liu, Jan Kautz, Zhangyang Wang, and Arash Vahdat.
2024. CamCo: Camera-Controllable 3D-Consistent Image-to-Video Generation.
arXiv preprint arXiv:2406.02509 (2024).
Zhuoyi Yang, Jiayan Teng, Wendi Zheng, Ming Ding, Shiyu Huang, Jiazheng Xu, Yuan-
ming Yang, Wenyi Hong, Xiaohan Zhang, Guanyu Feng, et al. 2024. CogVideoX:
Text-to-Video Diffusion Models with An Expert Transformer.
arXiv preprint
arXiv:2408.06072 (2024).
Mingqiao Ye, Martin Danelljan, Fisher Yu, and Lei Ke. 2025. Gaussian grouping: Segment
and edit anything in 3d scenes. In European Conference on Computer Vision. Springer,
162–179.
Taoran Yi, Jiemin Fang, Junjie Wang, Guanjun Wu, Lingxi Xie, Xiaopeng Zhang, Wenyu
Liu, Qi Tian, and Xinggang Wang. 2024. GaussianDreamer: Fast Generation from
Text to 3D Gaussians by Bridging 2D and 3D Diffusion Models. In CVPR.
Haiyang Ying, Yixuan Yin, Jinzhi Zhang, Fan Wang, Tao Yu, Ruqi Huang, and Lu Fang.
2024. Omniseg3d: Omniversal 3d segmentation via hierarchical contrastive learning.
In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition.
20612–20622.
Haoyu Zhao, Hao Wang, Xingyue Zhao, Hongqiu Wang, Zhiyu Wu, Chengjiang Long,
and Hua Zou. 2024. Automated 3D Physical Simulation of Open-world Scene with
Gaussian Splatting. arXiv preprint arXiv:2411.12789 (2024).
Yian Zhao, Wanshi Xu, Ruochong Zheng, Pengchong Qiao, Chang Liu, and Jie Chen.
2025. iSegMan: Interactive Segment-and-Manipulate 3D Gaussians. In Proceedings
of the Computer Vision and Pattern Recognition Conference (CVPR). 661–670.
Shijie Zhou, Haoran Chang, Sicheng Jiang, Zhiwen Fan, Zehao Zhu, Dejia Xu,
Pradyumna Chari, Suya You, Zhangyang Wang, and Achuta Kadambi. 2024. Fea-
ture 3dgs: Supercharging 3d gaussian splatting to enable distilled feature fields. In
Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition.
21676–21685.

<!-- page 10 -->
10
•
Clement Fuji Tsang, Anita Hu, Or Perel, Carsten Kolve, and Maria Shugrina
auto 3D
segment
manual
modes
ﬁ nal
result
1
2
3
4
5
(a) Segmentation pipeline.
frustum
project
(N)
2D box
select
(N)
2D box
select
(S)
frustum
project
(I)
SAM
select
(N)
frustum
project
(S)
1
2
3
4
5
6
7
2
(b) Working with modes.
2
3
1
(c) Depth projection.
(d) Comparison with GaussianEditor.
supersplat
ours
(e) Comparison with supersplat.
GARField 
(level=1)
GARField 
(level=1)
ours
ours
GARField 
(level=2)
GARField 
(level=0)
(f) Comparison with GARField.
SAM queries
input mask
(g) Automatic segmentation on LERF.
Fig. 8. Segmentation Results: We show the flexibility of our proposed segmentation toolkit (§4) in the figure above.
Acknowledgments

<!-- page 11 -->
ArtisanGS: Interactive Tools for Gaussian Splat Selection
with AI and Human in the Loop
•
11
frustum
project
(I)
auto
orient
1
2
3
4
(a) Orientation.
(b) Physics simulation of a 3DGS scene segmented with our method, using Simplicits [Modi et al. 2024].
A
B
D
C
A
B
D
C
A
B
D
C
(c) Targeted object editing with our method, showing original view (A), selected segment (B), and edited results (C, D).
Fig. 9. Applications: Our flexible segmentation toolkit can be used to enable user-guided orientation of 3DGS scenes (§6.1, Fig.9a). Segmentation and
orientation facilitate physics simulation directly over the captured 3DGS scene (§6.3, Fig.9b). Controllable selection also enables targeted object editing (§6.2,
Fig.9c).

<!-- page 12 -->
12
•
Clement Fuji Tsang, Anita Hu, Or Perel, Carsten Kolve, and Maria Shugrina
A
Comparison to Standard Software
Under controlled object-centric conditions (even as simple as sus-
pending an object on a string), it is possible to capture data where
one can easily select objects using simple techniques like bound-
ing boxes. However, there are many scenarios ’in the wild’ where
this might not be possible. Editing task, like moving or removing
specific objects, are heavily dependent on good selection tools. A
number of standard software applications address this problem:
Gaussian splat capturing solutions like Scaniverse [Niantic 2024]
or Polycam [Polycam 2024] allow bounding volume based selec-
tion. In addition KIRI Engine [KIRI Innovations 2024] as well as
Postshot [Jawset 2024] feature brush based selection, in many cases
the focus here is object extraction via deletion of unwanted parts
of the scan. Gaussian Splatting [Irrealix 2024a,b] for After Effects
[Adobe Systems 2024] and Nuke [Foundry 2024] allow integration
of Gaussian Splats into 2.5d image compositing pipelines - their
feature set matches the above. Dedicated Gaussian splat web apps
like Supersplat [PlayCanvas 2024] as well as extensions to game
engines XVERSE 3D-GS UE Plugin [XVERSE Technology Inc. 2024]
for Unreal Engine [Epic Games 2024b] or SplatVFX [Keijiro 2023]
for Unity [Unity Technologies 2024] expand the editing capabilities
by allowing manipulation using their standard tooling on a point
level. Extensions to standard 3D animation software like NerfStudio
[nerfstudio 2024] for Blender [The Blender Foundation 2024] offer a
similar feature set. In addition to cleanup, segmentation is used here
often to extract or modify individual features from a scan for down-
stream use. GSOPs [Rhodes and Diaz 2024] for Houdini [SideFX
2025] not only opens up the the use Houdini’s direct and procedural
tools for direct and indirect feature selection for Gaussian Splat
models, but also adds automatic clustering and segmentation based
on the DBSCAN algorithm [Ester et al. 1996].
While user-guided feature selection in Gaussian Splatting data
is the main focus of this paper, we nevertheless consider feature
selection in point cloud or volumetric data for industrial or medical
uses closely related: ReCap Pro [Autodesk 2024], Reality Capture
[Epic Games 2024a] and PIX4Dmatic [Pix4D 2024] are photogram-
metry solutions used in surveying, where a user might need to
identify elements of a scan (for example part of a worksite) for
further inspection.
In addition to the standard selection tools found in 3D-animation
software, we can find automatic and semi-automatic solutions that
help dealing with often large data volumes: Segments AI [Seg-
ments.ai 2024], Pointly [ Pointly GmbH 2024], Metashape [Agisoft
LLC 2024] and ArcGIS [Esri 2024] offer automatic machine learning
based feature classification for large scale data-labeling needs with
application in fields like city mapping or autonomous driving. In
medical imaging, a radiologist might need to select a organ from a
volumetric CT scan for further analysis. 3D Slicer [Various 2024]
is a popular tool that allows to automatically select such features
from a volumetric scan using machine learning with extensions like
TotalSegmentator [Wasserthal et al. 2023]. Here, ’region growing’ is
a semi-automatic technique where a user identifies ’seed points’ in
features used as reference data points for similarity based selection
expansion.
Ours
Ours (without pre-segmentation)
mIoU Acc mIoU Acc
fern
83.6
94.7 83.6
94.8
flower
97.9
99.5 97.9
99.5
fortress
98.5
99.7 98.3
99.7
horns left
0.0
94.0 92.7
99.4
horns center 97.4
99.4 97.4
99.4
leaves
96.4
99.8 96.6
99.8
orchids
96.6
99.2 96.7
99.2
trex
89.2
98.5 89.2
98.6
Table 4. NVOS Segmentation evaluation. The “horns_left” is failing with
pre-segmentation because the object is partially out of frame in the input
mask.
With Gaussian Splatting being adopted for industry use-cases, we
believe our research to be applicable and complementary to existing
tooling in these domains, too.
B
Evaluation Details
Breakdown of the NVOS results per testcases is presented in Table
1, showing that pre-segmentation only affects one example.
References
Pointly GmbH. 2024. Pointly. https://pointly.ai
Adobe Systems. 2024. After Effects.
Agisoft LLC. 2024. Agisoft Metashape. https://www.agisoft.com
Autodesk. 2024. ReCap Pro. https://www.autodesk.com/products/recap
Epic Games. 2024a. RealityCapture. https://www.capturingreality.com
Epic Games. 2024b. Unreal Engine. https://www.unrealengine.com
Esri. 2024. ArcGIS. https://www.arcgis.com
Martin Ester, Hans-Peter Kriegel, Jörg Sander, and Xiaowei Xu. 1996. A Density-
Based Algorithm for Discovering Clusters in Large Spatial Databases with Noise.
Proceedings of the Second International Conference on Knowledge Discovery and Data
Mining (KDD-96) (1996), 226–231.
Foundry. 2024. Nuke. https://www.foundry.com/products/nuke-family/nuke
Irrealix. 2024a. Gaussian Splatting for After Effects. https://aescripts.com/gaussian-
splatting/
Irrealix. 2024b. Gaussian Splatting for Nuke. https://aescripts.com/gaussian-splatting-
for-nuke
Jawset. 2024. Postshot. https://www.jawset.com/
Takahashi Keijiro. 2023. SplatVFX. https://github.com/keijiro/SplatVFX
KIRI Innovations. 2024. KIRI Engine. https://kiriengine.app
nerfstudio. 2024. Nerfstudio Blender Add-on.
https://docs.nerf.studio/extensions/
blender_addon.html
Niantic. 2024. Scaniverse. https://scaniverse.com
Pix4D. 2024. PIX4Dmatic. https://www.pix4d.com
PlayCanvas. 2024. SuperSplat. https://playcanvas.com/supersplat
Polycam. 2024. Polycam. https://poly.cam/
David Rhodes and Ruben Diaz. 2024. GSOPS: Gaussian Splatting Operators for Houdini.
https://github.com/david-rhodes/GSOPs
Segments.ai. 2024. Segments.ai. https://segments.ai/
SideFX. 2025. Houdini. https://www.sidefx.com/products/houdini/
The Blender Foundation. 2024. Blender. https://www.blender.org/
Unity Technologies. 2024. Unity. https://unity.com
Various. 2024. 3D Slicer. https://slicer.org
Jakob Wasserthal, Michael Meyer, Hanns-Christian Breit, Joshy Cyriac, Yanye Shan, and
Michael Segeroth. 2023. TotalSegmentator: robust segmentation of 104 anatomical
structures in CT images. arXiv preprint arXiv:2208.05868 (2023). https://github.com/
lassoan/SlicerTotalSegmentator Version 2.
XVERSE Technology Inc. 2024. XVERSE 3D-GS UE Plugin. https://github.com/xverse-
engine/XV3DGS-UEPlugin
