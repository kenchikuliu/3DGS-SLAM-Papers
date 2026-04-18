<!-- page 1 -->
DualPhys-GS: Dual Physically-Guided 3D Gaussian Splatting for
Underwater Scene Reconstruction
Jiachen Lia,b, Guangzhi Hana,b, Jin Wana,b, Yuan Gaoa,b and Delong Hana,b,∗
aKey Laboratory of Computing Power Network and Information Security, Ministry of Education, Shandong Computer Science Center (National
Supercomputer Center in Jinan), Jinan, China
bShandong Provincial Key Laboratory of Computing Power Internet and Service Computing, Shandong Fundamental Research Center for Computer
Science, Jinan, China
A R T I C L E I N F O
Keywords:
3D Reconstruction
3D Gaussian splatting
Underwater scenes
DualPhys-GS framework
A B S T R A C T
In 3D reconstruction of underwater scenes, traditional methods based on atmospheric optical models
cannot effectively deal with the selective attenuation of light wavelengths and the effect of suspended
particle scattering, which are unique to the water medium, and lead to color distortion, geometric
artifacts, and collapsing phenomena at long distances. We propose the DualPhys-GS framework to
achieve high-quality underwater reconstruction through a dual-path optimization mechanism. Our
approach further develops a dual feature-guided attenuation-scattering modeling mechanism, the
RGB-guided attenuation optimization model combines RGB features and depth information and can
handle edge and structural details. In contrast, the multi-scale depth-aware scattering model captures
scattering effects at different scales using a feature pyramid network and an attention mechanism.
Meanwhile, we design several special loss functions. The attenuation scattering consistency loss ensures
physical consistency. The water body type adaptive loss dynamically adjusts the weighting coefficients.
The edge-aware scattering loss is used to maintain the sharpness of structural edges. The multi-scale
feature loss helps to capture global and local structural information. In addition, we design a scene
adaptive mechanism that can automatically identify the water-body-type characteristics (e.g., clear coral
reef waters or turbid coastal waters) and dynamically adjust the scattering and attenuation parameters
and optimization strategies. Experimental results show that our method outperforms existing methods
in several metrics, especially in suspended matter-dense regions and long-distance scenes, and the
reconstruction quality is significantly improved.
1. Introduction
The importance of 3D reconstruction techniques for
underwater scenes is increasing with the growing demand
for marine resource exploitation and ecological monitoring.
However, compared with the atmospheric environment, the
available data for underwater scenes are limited by acquisition
costs and equipment conditions, and face unique physical
challenges: (1) Wavelength selective attenuation, the water
body absorbs light of different wavelengths with significant
differences, and in particular, long-wavelength light (e.g.,
red light) attenuates drastically with distance, resulting in
color distortion (typically blue-green hue), which affects the
color fidelity of the rendered image. (2) Multiple scattering
effect, Anisotropic scattering effect triggered by suspended
particles in water (e.g., plankton, organic debris and minerals).
In long-distance or turbid water bodies, forward scattering
makes the geometric structure blurred, background noise
more significant, and background scattering makes the image
‘foggy’, which reduces the accuracy of feature matching.
⋆This work is supported by project ZR2024QF286 supported by
Shandong Provincial Natural Science Foundation, National Key Research
and Development Program of China (NO. 2022YFB4004401), National
Natural Science Foundation of China (NO. 62202425), the Taishan Scholars
Program (NO. tsqnz20240834), the Qilu Youth Innovation Team (NO.
2024KJH028)
∗Corresponding author
jcli@qlu.edu.cn (J. Li); 10431240234@stu.qlu.edu.cn (G. Han);
wanj@qlu.edu.cn (J. Wan); yuangao@qlu.edu.cn (Y. Gao); handl@qlu.edu.cn
(D. Han)
ORCID(s): 0000-0002-3543-6088 (J. Li)
(3) Diversity of water environment, different water bodies
exhibit different optical properties, making it difficult for fixed
parameter models to maintain robustness in different water
environments. Traditional reconstruction methods based on
atmospheric optical models (e.g., MVS [1] ) in underwater
environments not only suffer from systematic deviations in
geometric accuracy, but also suffer from significant degrada-
tion in texture fidelity, seriously restricting the application
potential of underwater 3D reconstruction technology in
the fields of marine science, autonomous navigation of
underwater robots, and virtual underwater tours.
Neural Radiance Fields (NeRFs) [8] have demonstrated
their unique advantages in underwater scenes in recent
years, which effectively address some of the challenges in
underwater scenes by modeling implicit neural radiation
fields in conjunction with body rendering techniques. By
accumulating densities and colors along the light rays, volume
rendering can accurately simulate the translucency effect in
the water body and represent the complex optical interactions
between underwater objects and suspended particles at
different depths. In addition, the volume-integrated nature of
volume rendering helps to simulate the propagation process
of light rays in different aqueous media, further support-
ing the modeling of wavelength-dependent light transport.
However, NeRF-based methods [10] [17] [23] [26] are
usually accompanied by high computational overheads during
training and rendering, and cannot realize real-time rendering.
Meanwhile, during global optimization, it is difficult to
accurately distinguish the effects of wavelength-selective
Li et al.: Preprint submitted to Elsevier
Page 1 of 12
arXiv:2508.09610v1  [cs.GR]  13 Aug 2025

<!-- page 2 -->
DualPhys-GS
attenuation in body rendering, leading to color distortion
at long distances, and these limitations constrain its potential
application in real-time underwater scene reconstruction.
Recently, 3D Gaussian Splatting (3DGS) [12] based on
explicit Gaussian representations has made a breakthrough in
3D scene reconstruction. 3DGS [12] innovatively introduces
explicit 3D Gaussian representations and a differentiable ras-
terization pipeline, improving real-time rendering efficiency
while maintaining visual quality. In addition, its anisotropic
Gaussian primitives accurately model the geometric details
of the scene, effectively preserving the edge structure of the
underwater scene, and its transparency-based alpha blending
mechanism facilitates the integration of physically-based
color recovery models. However, the atmospheric medium-
based light transport assumption of 3DGS [12] faces a
fundamental limitation when directly migrated to underwater
scenes: it ignores the unique optical effects of the water
column. The wavelength-dependent attenuation of light by
the water column leads to a systematic color bias of distant
objects (especially a substantial loss of red information).
Anisotropic scattering effects induced by suspended particles
interfere with the depth-consistent estimation, leading to
biased reconstruction of the density field and geometric
structure. These problems are manifested in the 3D recon-
struction results as geometric artifacts in the distant seafloor
topography, systematic color bias in the coral reef texture,
and pseudo-volumetric effect on the scene surface.
To solve these problems, a 3DGS-based dual-path op-
timization framework is proposed. DualPhys-GS combines
with a dual-physics modeling scene adaptation method to
achieve high-quality reconstruction of underwater scenes.
The core innovation of DualPhys-GS lies in the design of a
feature-guided attenuation-scattering dual-modeling mech-
anism based on the feature-guided attenuation-scattering
mechanism, which accurately decomposes underwater opti-
cal propagation processes into two key physical processes,
namely, attenuation and scattering. For the attenuation pro-
cess, we design an RGB-guided attenuation optimization
model, which combines RGB features and depth information
to process the scene edges and structural details accurately,
and introduces the wavelength physics a priori, which sim-
ulates the water body’s differentiation of the absorption of
light at different wavelengths. For the scattering process, we
present a multi-scale depth-aware scattering model, which
captures the scattering effects at different scales through
a feature pyramid network and an attention mechanism.
To ensure that the reconstruction results conform to the
underwater optical laws, we design special loss functions
such as edge-aware scattering loss, multi-scale feature loss,
and attenuation-scattering consistency loss, guaranteeing the
system’s high-quality reconstruction capability in various
underwater environments. In addition, we realize a scene
adaptive mechanism for the diversity of underwater environ-
ments, which can automatically identify the type of water
body and dynamically adjust the optimization parameters and
strategies. In Summary, Our key contributions are as follows:
1. We propose a feature-guided attenuation-scattering
dual modeling mechanism based on an RGB-guided
attenuation optimization model and multi-scale depth-
aware scattering model to achieve accurate simulation
of underwater optical propagation processes.
2. We design edge-aware scattering loss, multi-scale
feature loss, attenuation scattering consistency loss,
and water body type adaptive loss to ensure that the
model output conforms to the laws of underwater
optical physics.
3. We propose a scene-adaptive mechanism that au-
tomatically recognizes the type of water body and
dynamically adjusts the optimization strategy to ensure
high-quality reconstruction in different underwater
scenes.
2. Related work
2.1. Underwater reconstruction based on
conventional multi-view geometry
Traditional underwater 3D reconstruction mainly relies
on Multi-View Stereo (MVS) [1]. To address the optical
interference of the water medium, researchers propose phys-
ical model-based compensation methods. Chambah et al.
[2] apply the Jaffe-McGlamery light transport equation to
underwater scenes, estimate the background scattered light
through a background scattering model, and combine it with
color correction to recover the target reflectivity. However,
this method is highly dependent on idealized water body as-
sumptions and performs erratically in real environments with
significant parameter variations. On the other hand, Drews-Jr
et al. [4] estimate the transmittance field by using the Dark
Channel Prior (DCP) [3], which effectively suppresses the
ambiguity effect caused by forward scattering. Nevertheless,
these methods rely on accurate calibration of the optical
parameters of the water body (e.g., attenuation coefficient,
scattering phase function) and have poor robustness in turbid
waters. In recent years, deep learning methods enter this
field. Li et al. [7] design a two-branch network to estimate
the medium parameters and scene depth separately, which
alleviates the dependence on physical priori parameters, but
the scarcity of supervised data and the diversity of water-body-
types make it difficult to generalize the model to underwater
environments with different optical properties.
Based on the above studies, traditional multi-view stereo
vision (MVS) [1] underwater reconstruction methods still
face four fundamental challenges. Firstly, the unique optical
properties of water bodies invalidate the assumptions of
traditional algorithms, which leads to significant degrada-
tion of underwater image feature matching quality. This
degradation becomes particularly severe in long-distance or
turbid regions where feature mismatch rates remain high. Sec-
ondly, physical model compensation methods generally suffer
from parameter sensitivity issues. These methods require
tedious manual parameter adjustments for different water
environments and lack self-adaptive mechanisms. Thirdly,
existing approaches struggle to simultaneously handle the
Li et al.: Preprint submitted to Elsevier
Page 2 of 12

<!-- page 3 -->
DualPhys-GS
dual effects of wavelength-selective attenuation and multiple
scattering effects. Their performance particularly deteriorates
in complex scenarios with drastic water type variations.
Finally, learning-based methods face limitations due to
the high cost of underwater data acquisition and labeling
difficulty. The scarcity of training data severely restricts
their generalization capability. These collective issues cause
traditional MVS methods [5] [15] in practical underwater
applications to exhibit three persistent artifacts: long-range
geometric collapse, blurred edge structures, and systematic
color distortion.
2.2. Underwater reconstruction based on NeRFs
Neural Radiation Fields (NeRFs) [8] achieve high-quality
3D reconstruction through implicit neural representation.
Their powerful implicit representation capability and volume
rendering mechanism provide new solutions for modeling
complex optical phenomena in underwater scenes, where
current approaches mainly follow two directions, physical
model enhancement and optical effects decoupling. Never-
theless, NeRF-based underwater reconstruction still faces
critical challenges caused by medium scattering.
In the physical model enhancement direction, WaterNeRF
[21] pioneers the integration of the Beer-Lambert attenuation
law with the volume rendering equation, successfully simulat-
ing wavelength-dependent light attenuation. This physically-
grounded formulation introduces rigorous radiative transfer
constraints, significantly improving color fidelity in long-
range underwater scenes. However, its neglect of scattering
effects limits its ability to address background radiation
interference from suspended particles.
For optical effects decoupling, Seathru-NeRF [27] achieves
breakthrough by explicitly modeling scattering medium
properties through light path decomposition. It enhances
reconstruction quality in turbid media by separating direct
transmission from scattered radiance. Despite this advance-
ment, the method relies on oversimplified assumptions of
globally homogeneous scattering coefficients, failing to
account for spatially varying water medium parameters. This
limitation becomes particularly pronounced in complex water
bodies with dynamic optical properties.
The optical effects decoupling strategy manifests in
two representative approaches, Ye et al.’s underwater light
field preservation method [9] and WaterHE-NeRF [18]. The
former implicitly models forward scattering through joint
optimization of the radiation field and optical transmission
paths. However, its reliance on isotropic phase function
approximations creates inherent limitations in characterizing
anisotropic scattering properties of suspended particles in
turbid waters. The latter innovatively decouples water refrac-
tion, surface fluctuation, and medium scattering into separate
implicit fields. While this decomposition enhances physical
interpretability, the computational complexity escalates ex-
ponentially, severely constraining rendering efficiency and
making real-time applications currently infeasible.
Recent advancements in Beyond NeRF Underwater [20]
push the boundaries further by implementing differentiable
ray tracing for joint optimization of target reflectivity
and medium parameters. This co-optimization framework
achieves state-of-the-art rendering accuracy but introduces
critical dependencies on dense depth sensor data. Con-
sequently, the method struggles in monocular or sparse-
view scenarios where depth information remains incomplete
or unreliable. The above methods commonly suffer from
coupled optimization of the background radiation field and
the target reflectivity, leading to color bias in the long-range
reconstruction.
2.3. Underwater reconstruction based on 3DGS
3D Gaussian Splatting (3DGS) [12] provides a new
paradigm for real-time underwater reconstruction with the
advantages of explicit Gaussian characterization and differen-
tial rasterization. Numerous enhancement methods have been
proposed to address challenging problems across various
domains. These approaches encompass anti-aliasing [6] [13],
deblurring [11] [16] [19], relighting [14] [24], sparse view
[22] [29], and diffusion models [25] [31].
In underwater scene reconstruction, WaterSplatting [34]
pioneers the adaptation of 3DGS [12] by incorporating
learnable wavelength-selective attenuation coefficients, but it
retains NeRF volumetric rendering. This approach effectively
compensates for long-range color distortion while main-
taining real-time efficiency, but its oversimplified physical
model completely neglects scattering effects, leading to
blurred edges and detail loss in turbid environments.} To
address this limitation, SeaSplat [28] introduces a com-
prehensive physical imaging model that embeds Henyey-
Greenstein phase functions within Gaussian attributes for
single-scattering approximation. Although this significantly
improves reconstruction quality in turbid waters, three critical
challenges persist: the single-scale representation fails to
resolve near-field details and far-field structural features,
the absence of multi-scattering and background radiation
modeling restricts physical accuracy, and the globally fixed
scattering residual parameters lack adaptability across diverse
water types from clear reefs to turbid coasts.
Recent advancements explore advanced parameterization
strategies. Aquatic-GS [32] implements hybrid implicit-
explicit characterization to predict spatially varying medium
parameters, enhancing adaptability to complex optical prop-
erties. However, its implicit component introduces additional
computational overhead, compromising the inherent real-
time advantage of 3DGS. Meanwhile, Gaussian Splashing
[30] focuses on dynamic effects through Gaussianized water
volume modeling, successfully simulating surface waves but
neglecting geometric accuracy optimization for static under-
water structures.UW-GS[37] introduces a color appearance
model and a physically-based density control mechanism that
focuses on dynamic object processing and the generation of
binary motion masks. The method handles underwater optical
effects through color appearance modeling and employs
physical density control to constrain the Gaussian distribution.
Although innovative in dealing with dynamic scenes, it still
has limitations in dealing with complex underwater optical
Li et al.: Preprint submitted to Elsevier
Page 3 of 12

<!-- page 4 -->
DualPhys-GS
phenomena. These developments collectively highlight the
ongoing tension between physical accuracy, computational
efficiency, and scenario adaptability in underwater 3DGS
applications.
Current underwater scene reconstruction methods face
three interlinked fundamental limitations rooted in physical
modeling and computational framework design. The inherent
coupling between attenuation and scattering parameters con-
stitutes a primary challenge, as underwater light propagation
simultaneously involves wavelength-dependent absorption
and multi-scale scattering phenomena. In turbid environments
dominated by suspended particles, existing frameworks
systematically overestimate attenuation coefficients while
underestimating scattering effects, whereas in clear waters
this parameter imbalance reverses. Such coupled miscalibra-
tions induce cumulative errors over long propagation paths,
manifesting as chromatic distortions and geometric collapse
of distant structures.
Furthermore, the optical heterogeneity across aquatic
environments, from the crystalline waters of coral reefs to
sediment-laden coastal zones, exposes critical adaptation
limitations. Fixed parameter configurations optimized for
specific water types fail to maintain performance consistency
when deployed in non-target environments, necessitating
manual recalibration during cross-scenario applications and
severely constraining operational flexibility. Compound-
ing these issues, the prevalent single-scale representation
paradigm proves inadequate for capturing multi-range optical
interactions. Near-field regions require high-frequency detail
preservation to resolve particulate scattering effects, while
far-field reconstruction demands robust structural coherence
maintenance. Current single resolution frameworks either
over smooth proximate details or discard critical background
features, particularly failing to represent the gradual transi-
tion of scattering characteristics across depth-varying water
columns.
3. Preliminaries
3.1. 3D Gaussian Splatting
3D Gaussian Splatting (3DGS) [12] is an explicit 3D
reconstruction scene representation that models a 3D scene
by expanding the point cloud into anisotropic Gaussian
primitives. Each Gaussian primitive 𝐺𝑖consists of a centre
position 𝝁𝒊, a covariance matrix 𝚺𝒊, and color attributes of
opacity 𝛼𝑖and viewpoint. The density distribution function
of Gaussian primitives is defined as follows:
𝐺𝑖(𝑥) = e−1
2 (𝑥−𝝁𝒊)T𝚺𝒊
−1(𝑥−𝝁𝒊)
(1)
where 𝝁𝒊∈ℝ3 denotes the spatial coordinates of the
centre of the ellipsoid, and the covariance matrix 𝚺𝒊=
𝑹𝒊𝑺𝒊
2𝑹T
𝑖denotes the shape and orientation of the Gaussian
ellipsoid. The 3D Gaussian is projected to the 2D plane along
any viewpoint. The projected 2D Gaussian maintains the
Gaussian distribution characteristics. The Jacobian matrix 𝑱
can compute its covariance matrix on the image plane, which
can satisfy the demand of real-time rasterization. Then, alpha
blending is performed to realize the semi-transparent effect
through the viewpoint of depth-ordered Gaussian primitives.
Given the pixel coordinates 𝑥on the image plane, its final
color 𝐶𝑖(𝑥) is calculated as follows:
𝐶𝑖(𝑥) =
𝑁
∑
𝑖=1
𝒄𝑖𝛼𝑖(𝑥)
𝑖−1
∏
𝑗=1
(1 −𝛼𝑗(𝑥))
(2)
where the color term 𝒄𝑖is encoded by the spherical harmonic
function (SH), while the density property 𝛼𝑖is derived from
Gaussian covariance, collectively defining the 𝑖-th Gaussian’s
photometric and geometric attributes.
3.2. Underwater physical imaging model
When reconstructing underwater scenes, the effects of
water as a medium need to be considered compared to
atmospheric media. Light propagating underwater undergoes
the interaction of attenuation and backscattering effects, lead-
ing to light absorption during underwater propagation and,
ultimately, to unnatural colors and artefacts in the rendered
image. Classical underwater image formation [5] can be
expressed as a linear superposition of directly transmitted
light and background scattered light with the following
expression:
𝑰(𝑥) = 𝑱(𝑥) ⋅𝑇D + 𝐵∞⋅(1 −𝑇B)
(3)
where 𝑰is the irradiance received by the pixel 𝑥out of
the sensor, 𝑱denotes the color when there is no water
attenuation, 𝑇D = exp (−𝛽𝑑(𝑥) ⋅𝑧(𝑥)) is the direct transmit-
tance, 𝐵∞denotes the background at infinite distance, 𝑇B =
exp (−𝛽𝑏(𝑥) ⋅𝑧(𝑥)) denotes the background transmittance,
and is correlated with the depth information 𝑧.
4. Method
4.1. Overviwe of Dualphys-GS
As shown in Figure 1, we devise a physics-driven dual-
path framework to constrain 3D Gaussian Splatting (3DGS)
[12] for underwater scene reconstruction, which requires
decoupling the original scene radiance 𝑱from water medium
effects through three coordinated stages. The input image
first undergoes water-type classification to automatically
configure environmental adaptation parameters, followed by
Structure-from-Motion (SfM) [33] processing to initialize
point clouds and camera poses. In the attenuation path,
an RGB feature extraction network collaborates with the
attenuation model to characterize wavelength-dependent
attenuation properties, while in the scattering path, a feature
pyramid network enhances the scattering model’s capacity to
represent multi-scale anisotropic scattering patterns. These
physically-derived attenuation and scattering estimates are
synthesized through a radiative transfer model to generate
final renderings. The training process incorporates four
complementary loss functions, the consistency loss 𝐿ab to
ensure the physical correlation between attenuation and
scattering, the water body adaptive loss 𝐿wat to dynamically
adjust the weighting coefficients, the edge-aware loss 𝐿edge
Li et al.: Preprint submitted to Elsevier
Page 4 of 12

<!-- page 5 -->
DualPhys-GS
Figure 1: The Pipeline of DualPhys-GS. We integrate the enhanced underwater physical imaging model with the 3DGS framework.
Our water body adaptation mechanism first automatically identifies different scenarios through RGB inputs, followed by a processing
pipeline comprising, 3DGS-based scene reconstruction, dual-path physical modeling with an RGB-guided attenuation model and
multi-scale depth-aware scattering model, and ultimately mutual constraint optimization through loss functions, where 𝛼and 𝛽
denote parameter weights, 𝑤represents water type categories, and 𝐿constitutes the compound loss function.
to maintain structural clarity, and the multi-scale feature loss
𝐿ms to capture structural information at different scales.
4.2. A dual attenuation-scattering modelling
mechanism based on feature guidance
The optical properties of underwater environments are far
more complex than those of atmospheric environments and
stem primarily from the effect of water as a medium on light
propagation. As light passes through a body of water, it is
affected by two main physical phenomena, light attenuation
and backscattering. Light attenuation causes color distortion
of objects at long distances, and backscattering introduces a
“foggy” effect in the image, resulting in poor reconstruction.
Traditional underwater physical imaging models are simple,
decomposing the underwater image into a combination of
attenuated direct light and scattered light. However, this
simplification cannot effectively deal with underwater scenes’
complexity, especially with edges, depth-varying regions,
and different water conditions. To address this problem,
we propose a feature-guided dual attenuation-scattering-
based modeling mechanism, which accurately decomposes
the underwater optical propagation process into two key
physical processes, attenuation and scattering, and models
them separately by feature enhancement. The underwater
image formation model we adopted can be represented as:
𝑰= 𝑱⋅𝑨(𝑫, 𝑰RGB) + 𝑩(𝑫)
(4)
where 𝑰is the observed underwater image, 𝑱is the real
image, 𝑨is the attenuation map, and 𝑩is the scattering
map. While this equation follows the classical underwater
physical imaging model framework, our fundamental con-
tribution lies in the sophisticated learning and optimization
of the attenuation map 𝑨and scattering map 𝑩. Our dual
modelling mechanism avoids parameters interfering with
each other by decoupling the optimization process of atten-
uation and scattering, and at the same time, introduces a
variety of feature-guided strategies to enhance the model
expression, RGB image-guided attenuation optimization and
depth information-guided scattering optimization, which
can accurately simulate optical phenomena in underwater
environments, and significantly improve the reconstruction
quality and physical accuracy.
4.2.1. Attenuation Module
Wavelength-selective attenuation is a key challenge in
underwater scene reconstruction. Due to the significant
difference in the absorption rates of different wavelengths of
light in the water body, red light (long wavelength) is rapidly
absorbed at the early stage of propagation, resulting in a
typical blue-green color tone of distant objects. In contrast,
blue light (short wavelength) has a stronger penetration ability
and can maintain its relative intensity at a longer distance.
To address this phenomenon, we design an RGB-guided
attenuation model that introduces edge feature information
of RGB images on top of depth information to enhance
the processing capability of complex boundary regions and
mitigate the boundary artifacts caused by the discontinuity
of the depth map through the edge-aware mechanism.
Our proposed attenuation model enhance depth informa-
tion utilization rather than simply introducing it, including
RGB image features and an edge-aware mechanism, which
can be expressed as:
𝑨(𝑫, 𝑰RGB) =exp
(
−
∑
𝑐∈{r,g,b}
𝒘𝑐⋅𝛽𝑐(𝑫)
⋅(1 −𝛾⋅𝐸(𝑰RGB, 𝑫)) ⋅𝑇(𝑰RGB) ⋅𝑫)
(5)
where 𝒘𝑐is the wavelength-dependent weight vector, 𝛽𝑐(𝑫)
is the base attenuation coefficient, 𝐸(𝑰RGB, 𝑫) is the edge
perception factor, and 𝛾is the edge modulation strength
constant. The RGB-guided attenuation model first extracts
the color distribution and texture information from the input
Li et al.: Preprint submitted to Elsevier
Page 5 of 12

<!-- page 6 -->
DualPhys-GS
image through the designed RGB extraction network. This
enables the attenuation model to identify color distortion
regions in the scene due to wavelength-selective attenuation.
Combining this RGB information with depth features, the
model is able to estimate the actual color applied to each
region more accurately.
4.2.2. Scattering Module
The scattering intensity increases exponentially with
depth as light propagates through a homogeneous body of
water, which can be expressed simply as:
𝑩= 𝐵∞(1 −e−𝛽⋅𝑑)
(6)
where 𝑩denotes the scattering map, 𝐵∞denotes the back-
ground color at infinity, 𝛽denotes the scattering coefficient,
and 𝑑denotes the depth.
Scattering effects induced by underwater suspended
particles are an important cause of degradation of recon-
struction quality, and they produce complex angle-dependent
scattering of incident light. In addition, unlike homoge-
neous atmospheric environments, water scattering is highly
anisotropic, and scattering from near- and far-field objects
behaves differently, making it difficult for a single-scale
model to accurately deal with both near-field details and
far-field overall characteristics at the same time.
We construct a multi-scale depth-aware scattering model
that introduces local structural features and captures depth
information at different scales through a feature pyramid
network. Our physics-guided feature networks are specifically
designed for underwater optical physics modeling, extract-
ing features with clear physical meanings including blue-
green channel ratios, edge gradients, and color saturation
distributions that directly correspond to water body types
and optical parameters. These features have demonstrated
robust performance through table 3. The model contains three
feature extraction branches dealing with original resolution,
1/2 and 1/4 resolution. The multi-scale features are computed
as:
𝑴(𝑫) = 𝑓att
(
Concat(𝑓1(𝑫),
𝑓2(𝑫↓2)↑2, 𝑓3(𝑫↓4)↑4
))
(7)
where 𝑫↓𝑛denotes down-sampling 𝑛times, (⋅)↑𝑛denotes
upsampling 𝑛times, 𝑓𝑖denotes the feature extraction function
at different scales, and 𝑓att denotes the attention enhancement
module. This design is able to focus on both local details and
global structure. In order to enhance the feature extraction,
we introduce a dual attention mechanism of channel and
space in the multi-scale scattering model. Channel attention
highlights key feature channels through adaptive weighting.
In contrast, spatial attention focuses on regions in the image
with significant scattering variations, enhancing the model’s
ability to adapt to different depths and water conditions
in different scenes. The near-field region relies on high-
resolution branches to capture fine edge and texture details. In
contrast, the far-field region relies on low-resolution branches
to capture the overall scattering trend. The computational
formula of our proposed multi-scale scattering model can be
expressed as:
𝑩(𝑫) = 𝐵∞⋅(1 −exp (−𝛽𝑏(𝑫) ⋅𝐶(𝑫)
⋅(1 −𝜆⋅𝐸𝑑(𝑫)) ⋅(1 + 𝛿⋅𝑴(𝑫) ⋅𝑫)
))
(8)
where 𝛽𝑏(𝑫) is the base scattering coefficient, 𝐶(𝑫) is the
depth confidence factor, 𝐸𝑑(𝑫) is the depth edge factor,
𝑴(𝑫) is the multiscale feature weights, and 𝜆and 𝛿are the
modulation factors. In addition, we design a depth confidence
assessment module to dynamically adjust the scattering
calculation according to the depth estimation reliability, and
mitigate the boundary artifacts caused by depth discontinuity
through the edge-aware processing mechanism, so as to
realize the accurate simulation of underwater scattering
phenomena.
4.2.3. Loss Function
In addition to the basic loss functions, we design
attenuation-scattering consistency loss, water body type
adaptive loss, edge-aware scattering loss, and multiscale
feature loss to ensure that our attenuation and scattering
models achieve high-quality reconstruction under a wide
range of complex conditions.
In underwater physical imaging models, both attenuation
and scattering exhibit specific depth-dependent physical laws,
where the scattering effect of the aqueous medium is en-
hanced with increasing depth, and the attenuation of directly
transmitted light intensifies. However, previous methods
usually optimize scattering and attenuation as independent
parameters and lack a physical constraint mechanism. This
results in unphysical phenomena of high scattering and
low attenuation for close objects, or low scattering and
high attenuation for far objects. This inconsistency seriously
affects the visual realism, so we devise the attenuation
scattering consistency loss:
𝐿ab = 𝔼[𝑩𝑠⋅𝑫] −𝔼[𝑨⋅𝑫] + 𝜇⋅MSE(𝑩𝑠+ 𝑻, 1)
(9)
where 𝔼denotes the expectation value, 𝑩𝑠denotes the
scattering component, 𝑫denotes the depth map, 𝑨denotes
the attenuation component, and 𝑻denotes the transmittance
map, i.e., the proportion of the original light that successfully
passes through the medium and reaches the camera in the
underwater scene. This consistency constraint consists of
the following three core components, a positive correlation
constraint between the scattering term 𝑩𝑠and the depth 𝑫, a
negative correlation constraint between the attenuation term
𝑨and the depth 𝑫, and a constraint on the complementarity
of the scattering and transmittance 𝑻. With the above three
physical consistency constraints, we ensure that the rendered
image is more consistent with the underwater imaging laws
at the physical level, enhancing the overall visual realism.
Different water body types have significantly different
optical properties, in turbid water bodies, the scattering
effect is more significant, while in clear water bodies, the
attenuation effect is more prominent. In order to adapt to
Li et al.: Preprint submitted to Elsevier
Page 6 of 12

<!-- page 7 -->
DualPhys-GS
this difference, we designed a water body type adaptive
loss function, which estimates the water body type index
by analyzing the color distribution characteristics of the
image (mainly the ratio of blue and green channels) and
then dynamically adjusts the weights of each part of the loss
function to achieve adaptive optimization for different water
body environments. This adaptive mechanism eliminates
the need for manual parameter tuning when applying our
method to new datasets. The system automatically identifies
water types and adjusts optimization strategies accordingly,
ensuring consistent superior performance across diverse
underwater environments ranging from clear coral reefs to
turbid coastal waters without requiring intervention. The
expression can be expressed as:
𝐿wat = 𝛼(𝑤) ⋅𝐿attenuation + 𝛽(𝑤) ⋅𝐿scattering + 𝛾⋅𝐿ab (10)
where the weighting coefficients 𝛼(𝑤) and 𝛽(𝑤) are dynami-
cally determined by the water body type 𝑤. We estimate the
optical properties of the current water body by mapping the
blue-to-green channel ratio of the image to a standardized
water body type indicator 𝑤. In clear water bodies, the model
increases the weight of attenuation loss, while in turbid
water bodies, it enhances the weight of scattering loss. This
mechanism allows the training process to adapt to different
water body conditions, improving the robustness and accuracy
of the model’s reconstruction in multiple environments.
In underwater scenes, the edges of the scene usually
correspond to depth-continuous regions. The scattering
characteristics of these regions are significantly different from
those of the depth-continuous regions, which makes it diffi-
cult for conventional scattering models to accurately deal with
the scattering discontinuities at the edges, leading to problems
such as blurred edges and distorted structures, which seriously
affects the visual realism and geometric accuracy of the
rendered image, especially in scenes with complex structures
such as coral reefs, and so forth. Especially in scenes with
complex structures such as coral reefs. To this end, we design
a depth-aware edge loss to impose constraints on the imaging
characteristics of the scattering and attenuation edge regions
to effectively improve the imaging quality and geometric
structure preservation ability at the edges. The depth-aware
edge loss expression is given by:
𝐿edge = 𝐿1(𝑩𝑠⋅𝑾edge,0) + 𝜆⋅
∑
𝑝
𝑾smooth(𝑝)
⋅(|∇𝑥𝑩𝑠(𝑝)| + |∇𝑦𝑩𝑠(𝑝)|)
(11)
where 𝑾edge is the depth edge weight, which is dynam-
ically assigned according to the magnitude of the local
depth gradient, 𝑾smooth(𝑝) = e−𝛼⋅(|∇𝑥𝑑(𝑝)|+|∇𝑦𝑑(𝑝)|) is the
smoothing constraint weight, which is used to maintain the
sharpness of the edges of the structure. This loss function
imposes stronger constraints in the edge region where the
depth varies drastically, prompting the scattering model to
learn accurate scattering properties at the edges instead of
a simple smoothing process. The mechanism pays special
attention to the imaging performance at the junction of the
foreground object contour and the background water body.
It can accurately model the scattering transition between the
foreground and the background, effectively mitigating the
problems of edge blurring and structural distortions, thus
significantly improving the edge fidelity in the reconstruction
of underwater scenes.
Since it is difficult to capture high-frequency details
and low-frequency structural information in an image at a
single scale, we propose a multi-scale feature loss function.
The function captures global structural and local detail
information by comparing the model output with the target
image at multiple spatial scales. The expression is as follows:
𝐿ms = 𝐿1(𝑶, 𝑻) + 𝜆ms
|𝑺|
∑
𝑠∈𝑺
𝐿1(𝐷𝑠(𝑶), 𝐷𝑠(𝑻))
(12)
where 𝑶is the rendered image, 𝑻is the real image, 𝑺
is a set of scale factors for downsampling, including the
original resolution, 1∕2 and 1∕4 resolution, 𝜆ms is the weight
coefficients, and 𝐷𝑠denotes the downsampling processing of
the input image and the rendered image at scale 𝑠. 𝐿1(𝑶, 𝑻)
denotes the computation of the 𝐿1 loss under the original
resolution, and the subsequent terms denote the computation
of the loss under the various downsampling scales. By
combining the structural losses at different scales, this loss
function can maintain consistency at the global layout and
local detail levels simultaneously, thus effectively improving
the structural fidelity of the rendering results.
Finally, our total loss function expression is:
𝐿total = 𝑤1𝐿basic + 𝑤2𝐿ab
+ 𝑤3𝐿wat + 𝑤4𝐿edge + 𝑤5𝐿ms
(13)
4.2.4. Scene Adaptive Mechanism
We propose a complete set of scene adaptive mechanisms,
which enables DualPhys-GS to dynamically adjust its op-
timization strategy according to the optical characteristics
of different water environments, thus adapting to diverse
underwater scenes.
Different water bodies have significantly different optical
properties, and it isn’t easy to adapt to diverse underwater
environments if a fixed single-parameter model is used. There-
fore, we developed a classifier to automatically recognize the
water body type (clear, medium, turbid) based on the input
RGB image features with the following expression:
𝑇(𝑰RGB) =Softmax
(𝑾2 ⋅ReLU (𝑾1 ⋅AvgPool(𝑰RGB)))
(14)
where 𝑰RGB is the input RGB image, the classifier can
evaluate the optical properties of the underwater environment
in real-time and realize adaptive processing for different
underwater environments.
Different water environments require targeted optimiza-
tion strategies to achieve optimal reconstruction results.
In order to realize the environment-adaptive optimization
process, we designed an adaptive optimization controller
to dynamically adjust the training strategy according to
Li et al.: Preprint submitted to Elsevier
Page 7 of 12

<!-- page 8 -->
DualPhys-GS
Table 1
Quantitative comparisons. Qualitative results of the evaluation of the proposed method on the SeaThru-NeRF dataset [27]. "↑"
indicates that larger values are better, while ’↓’ is the opposite (smaller values are better). Values in red indicate the best results,
and values in green represent the second-best results within the 3DGS category.
Category
Method
SeaThru-NeRF
SaltPond
Curasao
Japanese Gardens
IUI3
Panama
SaltPond
PSNR↑SSIM↑LPIPS↓PSNR↑SSIM↑LPIPS↓PSNR↑SSIM↑LPIPS↓PSNR↑SSIM↑LPIPS↓PSNR↑SSIM↑LPIPS↓
NeRF
Seathru-NeRF [27]
30.08
0.87
0.19
21.74
0.77
0.29
26.01
0.79
0.32
27.69
0.83
0.28
11.93
0.51
0.58
NeRF+3DGS WaterSplatting [34]
32.67
0.96
0.11
25.20
0.90
0.11
29.39
0.91
0.18
30.49
0.95
0.08
26.83
0.66
0.38
3DGS
3DGS [12]
28.01
0.88
0.21
21.47
0.85
0.22
21.11
0.81
0.29
29.64
0.90
0.17
27.10
0.75
0.29
Seasplat [28]
30.30
0.90
0.19
22.70
0.87
0.18
26.67
0.87
0.21
28.76
0.90
0.15
27.47
0.75
0.25
UW-GS[37]
31.77
0.94
0.14
23.05
0.86
0.19
28.65
0.93
0.13
31.79
0.94
0.12
-
-
-
Ours
30.48
0.91
0.19
22.77
0.87
0.18
27.86
0.87
0.23
29.9
0.91
0.14
28.03
0.77
0.25
Figure 2: Comparison of novel synthesis methods based on underwater media. Dualphys-GS exhibits high-quality rendering results.
the water body attributes identified by the water body type
classifier. The controller mainly consists of the following two
functional modules, learning rate adjustment, for the clear
water environment, the learning rate is automatically reduced
to promote finer parameter convergence. loss function weight
adjustment, using the water body type adaptive loss function,
the weights of the scattering and attenuation losses are
dynamically assigned based on the water body clarity, and
the weight of the scattering constraints is increased in
the turbid water. in the clear water, the focus is on the
attenuation constraints. Through the synergy between the
water body type classifiers and the adaptive optimization
controllers, we realize the adaptive optimization strategy in
diverse underwater environments, significantly improving the
model’s generalization ability and reconstruction accuracy
in different scenarios.
5. Experiments
5.1. Datasets
To validate the effectiveness of the proposed method, we
use the multi-view underwater scene dataset published by
SeaThru-NeRF [27] and the SaltPond dataset for experimen-
tal evaluation. The SeaThru-NeRF dataset [27] covers typical
underwater scenes from multiple sea areas, including four sub-
scenes: Japanese Gardens, IUI3, Curasao, and Panama. These
scenes are rich in depth variations and optical diversities and
can comprehensively reflect the imaging characteristics in
different water body environments.
5.2. Evaluation Metrics
We chose three widely used image evaluation metrics to
validate the new perspective synthesis effect. We assessed
the visual fidelity by comparing the final obtained rendered
Li et al.: Preprint submitted to Elsevier
Page 8 of 12

<!-- page 9 -->
DualPhys-GS
Figure 3: Model Ablations in IUI3-RedSea from Seathru-NeRF dataset [27]. We have shown partial details of rendered images
with progressive module integration.
Figure 4: Loss Ablations in IUI3-RedSea from Seathru-NeRF dataset [27]. We have shown partial details of rendered images with
progressive loss function integration.
image with the real image through the peak signal-to-noise
ratio (PSNR), the structural similarity index (SSIM) [35],
and the perceptual image block similarity (LPIPS) [36].
5.3. Implementation Details
Before training begins, we use COLMAP [33] to get an
initialized point cloud and estimate the camera position. The
number of training iterations for all scenes is 30,000, and un-
derwater color rendering is turned on at 10,000 iterations. In
the initialization phase, we designed a scene adaptation mech-
anism for different underwater environments to automatically
recognize five main water types (Curasao, JapaneseGradens-
RedSea, IUI3-RedSea, Panama, and SaltPond). During the
training process, we use the Adam optimizer to optimize
the Gaussian representation parameters, scattering model
and attenuation model. The learning rate thresholds for
the attenuation and scattering models are set to 5e−4 and
1e−4, respectively, with optimization strategies adjusted
by our scene-adaptive mechanism for different water body
environments. For water bodies classified as "clear" (e.g.,
Curasao), the learning rates of the attenuation and scattering
models are dynamically reduced from 1e−4 to 5e−5 for
fine optimization, while the water body type adaptive loss
𝐿wat increases the weight of the attenuation loss 𝛼(𝑤) to
1.2 and decreases the weight of the scattering loss 𝛽(𝑤) to
0.8. Additionally, in "turbid" water bodies (e.g., IUI3), the
learning rate is maintained at 1e−4 to accelerate convergence,
while the weight of scattering loss 𝛽(𝑤) is increased to 1.2
and the weight of attenuation loss 𝛼(𝑤) is reduced to 0.8 to
strengthen constraints on scattering effects. This automated
parameter adjustment strategy is the key to ensuring the
effectiveness of our method across diverse datasets. All
experiments in this paper are done on a single workstation
configured with an Intel Core i9-13900K processor, 64GB
DDR5 memory, and an NVIDIA GeForce RTX 4090 graphics
card (24GB video memory).
5.4. Results and Discussion
5.4.1. Quantitative results
Table 1 presents a comprehensive evaluation of different
methods on the SeaThru-NeRF dataset [27] and the Salt-
Pond dataset. In terms of quantitative metrics, WaterSplat-
ting [34] demonstrates a significant advantage in PSNR on
the SeaThru-NeRF dataset. This primarily stems from its
regularization loss function, which more directly fits the
visual characteristics of target images. Notably, while our
method exhibits a performance gap in pure numerical metrics,
we prioritize fidelity in physical process modeling over solely
pursuing visual feature fitting. In addition, WaterSplatting
[34] does not use the 3DGS framework.
Compared to UW-GS [37], which achieves superior
PSNR performance on most SeaThru-NeRF scenes, it should
be noted that UW-GS leverages the pre-trained depth estima-
tion model DepthAnything [38] to enhance depth accuracy. In
contrast, our approach relies solely on the depth information
rendered by 3DGS without external depth priors, demonstrat-
ing the effectiveness of our physics-guided dual modeling
strategy under more constrained conditions.
This design distinction manifests in the SaltPond dataset
results. DualPhys-GS achieves the highest PSNR value of
28.03 on this dataset, surpassing all comparative methods
including WaterSplatting [34]. This indicates that physics-
constrained modeling methods exhibit greater generalization
potential when confronted with diverse aquatic environments.
In the Structural Similarity (SSIM) [35] assessment,
despite the PSNR gap, DualPhys-GS consistently achieves
SSIM scores comparable to the best-performing methods
across multiple scenes. This suggests an advantage in pre-
serving structural image integrity for our approach, likely
attributed to its physics-based modeling properties.
The perceptual quality metric (LPIPS) [36] further sup-
ports the effectiveness of our method. In scenes such as
Li et al.: Preprint submitted to Elsevier
Page 9 of 12

<!-- page 10 -->
DualPhys-GS
Table 2
Comparison of rendering times for different methods on the
Seathru-NeRF dataset.
Method
Rendering Time
Watersplatting [34]
0.084 s
3DGS [12]
0.006 s
SeaSplat[28]
0.012 s
Ours
0.016 s
Curasao and Japanese Gardens, DualPhys-GS yields percep-
tual quality on par with top methods. This implies that despite
pixel-level accuracy differences, the reconstruction results
from our method exhibit comparable perceptual acceptability
from a human visual perspective.
Regarding computational efficiency, DualPhys-GS demon-
strates a substantial advantage. Its rendering time of 0.016s
represents an approximately 5-fold improvement over Water-
Splatting’s 0.084s.
5.4.2. Qualitative results
Regarding visual reconstruction quality, the comparison
of the rendering results in Figure 2 reveals the differences
in the characteristics of the different methods. Our proposed
DualPhys-GS method performs well in terms of reconstruc-
tion quality due to its innovative dual-path optimization
mechanism.
Traditional 3DGS [12] methods often suffer from unsta-
ble Gaussian distributions in scenes with complex geometries,
such as the coral reefs in Panama. In contrast, our method can
accurately recover the color information of distant objects
through the RGB-guided attenuation model, especially the
long-wavelength red channel, which successfully solves the
problem of distant objects’ unnatural bluish-green hue.
At the same time, the multi-scale scattering model can
accurately capture the scattering effects at different scales,
which enables the model to generate smooth and continuous
depth estimation in the underwater environment while pre-
serving the detailed features. Furthermore, the water type
adaptation mechanism enables the model to automatically
adjust the optimization strategy according to different water
environments, thus maintaining excellent performance under
various water conditions and demonstrating high adaptability
to complex underwater environments.
5.5. Ablation Study
Through Table 3, we systematically evaluate the ef-
fectiveness of key components in DualPhys-GS, including
feature-guided attenuation-scattering modeling, aquatic scene
adaptation module, and analyzing the effects of different loss
functions. Our experiments are conducted on the SeaThru-
NeRF dataset, with comparative analysis of average PSNR,
SSIM, and LPIPS values across four scenes to elucidate
the impacts of individual modules and loss terms on model
performance.
Table 3
Ablations. We measure the average values of all metrics
across the Seathru-NeRF dataset, where RGBAt is RGB-guided
attenuation optimization model, MSBs is multi-scale depth-
aware scattering model and WAT is water body scene adaptive
module based on RGB guidance and loss function.
Metrics
PSNR↑SSIM↑LPIPS↓
Total
27.63
0.89
0.19
Model
RGBAt only
26.86
0.88
0.19
MSBs only
27.07
0.89
0.19
WAT only
27.20
0.89
0.18
RGBAt+MSBs
27.27
0.89
0.18
RGBAt+MSBs+WAT
27.29
0.89
0.18
Loss
𝐿wat only
27.08
0.88
0.18
𝐿ms only
27.14
0.89
0.19
𝐿ab only
27.39
0.89
0.19
𝐿ab+𝐿wat
27.40
0.89
0.18
𝐿ab+𝐿wat+𝐿ms
27.57
0.89
0.19
𝐿ab+w/o WAT
27.47
0.89
0.18
5.5.1. Model Ablation
Quantitative results from Table 3 and visualizations in
Figure 3 demonstrate that the complete DualPhys-GS model
achieves optimal reconstruction quality. In contrast, using
only the RGB feature-based attenuation model or the multi-
scale depth-aware scattering model individually results in
compromised performance. This validates that our dual-
branch modeling mechanism effectively integrates RGB
features with depth information to address underwater chal-
lenges including long-range color distortion and wavelength-
selective attenuation, while the multi-scale scattering model-
ing employs feature pyramid architecture to capture scattering
effects across scales, thereby enhancing detail preservation.
Furthermore, the water-body-type adaptation module
contributes significantly to performance improvement. When
activated independently, this module dynamically adjusts
optimization strategies according to water characteristics,
outperforming single-module configurations. The combina-
tion of RGB attenuation and multi-scale scattering modules
achieves incremental quality gains, with the full model
exhibiting synergistic effects that maximize complementary
advantages among components, ultimately attaining best
results.
5.5.2. Loss Ablation
Our ablation studies further validate the importance of
individual loss functions. The visual details in Figure 4
demonstrate concrete improvements, while Table 3 quan-
titatively reveals that the attenuation-scattering consistency
loss plays a pivotal role in performance enhancement. When
exclusively employing this loss, the model achieves supe-
rior reconstruction quality compared to using only scene-
adaptive loss or multi-scale feature loss. This confirms that
Li et al.: Preprint submitted to Elsevier
Page 10 of 12

<!-- page 11 -->
DualPhys-GS
physical consistency constraints (e.g., positive scattering-
depth correlation, negative attenuation-depth relationship,
and scattering-transmittance complementarity) are vital for
accurate underwater scene reconstruction.
The synergistic combination of attenuation-scattering
consistency loss with scene-adaptive loss enables the model
to maintain physical plausibility while adapting to diverse
aquatic environments. Subsequent integration of multi-scale
feature loss strengthens the model’s capacity to capture both
global structures and local details, yielding incremental qual-
ity gains. Notably, even with all three loss terms integrated,
the model still exhibits degraded reconstruction when lacking
the aquatic-type adaptation mechanism.
6. Limitations
Before deploying DualPhys-GS in real-world underwater
application scenarios, the method must be adapted and
optimized for efficient operation in real-time environments,
especially for computational optimization in dynamically
constructing 3D Gaussian representations. This has potential
applications for autonomous underwater navigation and
adaptive sampling in special areas such as coral reefs. Al-
though our framework accurately models the attenuation and
scattering effects of the water column through a dual-path
optimization mechanism, there are still some limitations in
terms of the completeness of the optical modeling: the focal
dispersion phenomenon resulting from refraction at the water
surface, as well as the impact of underwater equipment (e.g.,
divers or camera devices) on the scene illumination, which is
particularly noticeable in some datasets (e.g., SaltPond), are
not adequately taken into account. In addition, real underwa-
ter environments are full of dynamic elements (e.g., seaweed
swaying with the current or fish swimming). DualPhys-GS
is currently optimized for static underwater scenes, so the
ability to model dynamic underwater scenes or objects needs
to be further enhanced.
7. Conclusions
In this paper, we propose a dual-path optimization frame-
work DualPhys-GS based on 3DGS [12] to address the color
distortion and geometric artifacts in 3D reconstruction of
underwater scenes, and we achieve an accurate simulation
of underwater optical propagation through a feature-guided
attenuation-scattering dual modeling mechanism. The RGB-
guided attenuation optimization model combines RGB fea-
tures and depth information to deal with scene boundaries and
structural details accurately. In contrast, the multi-scale depth-
aware scattering model captures the optical effects at different
scales through a feature pyramid network and an attention
mechanism. A series of loss functions (e.g., edge-aware
scattering loss, multi-scale feature loss, attenuation scattering
consistency loss, etc.) are designed to ensure that the model
outputs are consistent with the physical laws of underwater
optics. In addition, the scene adaptation mechanism can
automatically recognize the water type according to the image
features and adjust the parameters accordingly so as to adapt
to different underwater environments, from clear to turbid.
Experimental results show that DualPhys-GS significantly
improves the reconstruction’s geometric accuracy and texture
fidelity in complex underwater scenes, especially in areas
with dense suspended objects and long-distance seabed
terrain.
References
[1] Yasutaka Furukawa, Carlos Hernández. Multi-View Stereo: A Tu-
torial. Foundations and Trends in Computer Graphics and Vision,
9(1-2): 1-148 (2015).
[2] Majed Chambah, Dahbia Semani, Arnaud Renouf, Pierre Courtelle-
mont, Alessandro Rizzi. Underwater color constancy: enhancement
of automatic live fish recognition. In Color Imaging: Processing,
Hardcopy, and Applications 2004: 157-168.
[3] Kaiming He, Jian Sun, Xiaoou Tang. Single image haze removal
using dark channel prior. In Proceedings of the IEEE Conference on
Computer Vision and Pattern Recognition (CVPR) 2009: 1956-1963.
[4] Paulo Drews Jr., Erickson Rangel do Nascimento, F. Moraes, Silvia
S. C. Botelho, Mario F. M. Campos. Transmission Estimation in
Underwater Single Images. In Proceedings of the IEEE International
Conference on Computer Vision Workshops (ICCV Workshops) 2013:
825-830.
[5] Derya Akkaynak, Tali Treibitz. A Revised Underwater Image For-
mation Model. In Proceedings of the IEEE Conference on Computer
Vision and Pattern Recognition (CVPR) 2018: 6723-6732.
[6] Yunzhou Song, Heguang Lin, Jiahui Lei, Lingjie Liu, Kostas Dani-
ilidis. HDGS: Textured 2D Gaussian Splatting for Enhanced Scene
Rendering. arXiv preprint arXiv:2412.01823, 2024.
[7] Jie Li, Katherine A. Skinner, Ryan M. Eustice, Matthew Johnson-
Roberson. WaterGAN: Unsupervised Generative Network to Enable
Real-Time Color Correction of Monocular Underwater Images. IEEE
Robotics and Automation Letters, 3(1): 387-394 (2018).
[8] Ben Mildenhall, Pratul P. Srinivasan, Matthew Tancik, Jonathan T.
Barron, Ravi Ramamoorthi, Ren Ng. NeRF: representing scenes as
neural radiance fields for view synthesis. Communications of the
ACM, 65(1): 99-106 (2022).
[9] Tian Ye, Sixiang Chen, Yun Liu, Yi Ye, Erkang Chen, Yuche Li.
Underwater Light Field Retention: Neural Rendering for Underwater
Imaging. In Proceedings of the IEEE/CVF Conference on Computer
Vision and Pattern Recognition Workshops (CVPR Workshops) 2022:
487-496.
[10] Jonathan T. Barron, Ben Mildenhall, Matthew Tancik, Peter Hedman,
Ricardo Martin-Brualla, Pratul P. Srinivasan. Mip-NeRF: A Multi-
scale Representation for Anti-Aliasing Neural Radiance Fields. In
Proceedings of the IEEE/CVF International Conference on Computer
Vision (ICCV) 2021: 5835-5844.
[11] Renlong Wu, Zhilu Zhang, Mingyang Chen, Xiaopeng Fan, Zifei Yan,
Wangmeng Zuo. Deblur4DGS: 4D Gaussian Splatting from Blurry
Monocular Video. arXiv preprint arXiv:2412.06424, 2024.
[12] Bernhard Kerbl, Georgios Kopanas, Thomas Leimkühler, George
Drettakis. 3D Gaussian Splatting for Real-Time Radiance Field
Rendering. ACM Transactions on Graphics, 42(4): 139:1-139:14
(2023).
[13] Jorge Condor, Sébastien Speierer, Lukas Bode, Aljaz Bozic, Simon
Green, Piotr Didyk, Adrián Jarabo. Don’t Splat your Gaussians:
Volumetric Ray-Traced Primitives for Modeling and Rendering
Scattering and Emissive Media. ACM Transactions on Graphics,
44(1): 10:1-10:17 (2025).
[14] Yingwenqi Jiang, Jiadong Tu, Yuan Liu, Xifeng Gao, Xiaoxiao Long,
Wenping Wang, Yuexin Ma. GaussianShader: 3D Gaussian Splatting
with Shading Functions for Reflective Surfaces. In Proceedings of the
IEEE/CVF Conference on Computer Vision and Pattern Recognition
(CVPR) 2024: 5322-5332.
[15] Fushuo Huo, Bingheng Li, Xuegui Zhu. Efficient Wavelet Boost
Learning-Based Multi-stage Progressive Refinement Network for
Li et al.: Preprint submitted to Elsevier
Page 11 of 12

<!-- page 12 -->
DualPhys-GS
Underwater Image Enhancement. In Proceedings of the IEEE/CVF
International Conference on Computer Vision Workshops (ICCVW)
2021: 1944-1952.
[16] Jeongtaek Oh, Jaeyoung Chung, Dongwoo Lee, Kyoung Mu Lee.
DeblurGS: Gaussian Splatting for Camera Motion Blur. arXiv
preprint arXiv:2404.11358, 2024.
[17] Wenjing Bian, Zirui Wang, Kejie Li, Jia-Wang Bian. NoPe-NeRF:
Optimising Neural Radiance Field with No Pose Prior. In Proceedings
of the IEEE/CVF Conference on Computer Vision and Pattern
Recognition (CVPR) 2023: 4160-4169.
[18] Jingchun Zhou, Tianyu Liang, Zongxin He, Dehuan Zhang, Weishi
Zhang, Xianping Fu, Chongyi Li. WaterHE-NeRF: Water-ray Tracing
Neural Radiance Fields for Underwater Scene Reconstruction. arXiv
preprint arXiv:2312.06946, 2023.
[19] Gaole Dai, Zhenyu Wang, Qinwen Xu, Ming Lu, Wen Chen, Boxin
Shi, Shanghang Zhang, Tie-Jun Huang. SpikeNVS: Enhancing Novel
View Synthesis from Blurry Images via Spike Camera. arXiv preprint
arXiv:2404.06710, 2024.
[20] Tianyi Zhang, Matthew Johnson-Roberson. Beyond NeRF Underwa-
ter: Learning Neural Reflectance Fields for True Color Correction
of Marine Imagery. IEEE Robotics and Automation Letters, 8(10):
6467-6474 (2023).
[21] Advaith Venkatramanan Sethuraman, Manikandasriram Srinivasan
Ramanagopal, Katherine A. Skinner. WaterNeRF: Neural Radiance
Fields for Underwater Scenes. arXiv preprint arXiv:2209.13091,
2022.
[22] Han Huang, Yulun Wu, Chao Deng, Ge Gao, Ming Gu, Yu-Shen
Liu. FatesGS: Fast and Accurate Sparse-View Surface Reconstruc-
tion Using Gaussian Splatting with Depth-Feature Consistency. In
Proceedings of the AAAI Conference on Artificial Intelligence 2025:
3644-3652.
[23] Yunkai Tang, Chengxuan Zhu, Renjie Wan, Chao Xu, Boxin Shi.
Neural Underwater Scene Representation. In Proceedings of the
IEEE/CVF Conference on Computer Vision and Pattern Recognition
(CVPR) 2024: 11780-11789.
[24] Jingzhi Li, Zongwei Wu, Eduard Zamfir, Radu Timofte. ReCap:
Better Gaussian Relighting with Cross-Environment Captures. arXiv
preprint arXiv:2412.07534, 2024.
[25] Chenguo Lin, Panwang Pan, Bangbang Yang, Zeming Li, Yadong
Mu. DiffSplat: Repurposing Image Diffusion Models for Scalable
Gaussian Splat Generation. arXiv preprint arXiv:2501.16764, 2025.
[26] Andrea Ramazzina, Mario Bijelic, Stefanie Walz, Alessandro Sanvito,
Dominik Scheuble, Felix Heide. ScatterNeRF: Seeing Through Fog
with Physically-Based Inverse Neural Rendering. In Proceedings of
the IEEE/CVF International Conference on Computer Vision (ICCV)
2023: 17911-17922.
[27] Deborah Levy, Amit Peleg, Naama Pearl, Dan Rosenbaum, Derya
Akkaynak, Simon Korman, Tali Treibitz. SeaThru-NeRF: Neural
Radiance Fields in Scattering Media. In Proceedings of the IEEE/CVF
Conference on Computer Vision and Pattern Recognition (CVPR)
2023: 56-65.
[28] Daniel Yang, John J. Leonard, Yogesh A. Girdhar. SeaSplat: Rep-
resenting Underwater Scenes with 3D Gaussian Splatting and
a Physically Grounded Image Formation Model. arXiv preprint
arXiv:2409.17345, 2024.
[29] Cai Xudong Cai, Yongcai Wang, Zhaoxin Fan, Haoran Deng, Shuo
Wang, Wanting Li, Deying Li, Lun Luo, Minhang Wang, Jintao Xu.
Dust to Tower: Coarse-to-Fine Photo-Realistic Scene Reconstruction
from Sparse Uncalibrated Images. arXiv preprint arXiv:2412.19518,
2024.
[30] Nir Mualem, Roy Amoyal, Oren Freifeld, Derya Akkaynak. Gaussian
Splashing: Direct Volumetric Rendering Underwater. arXiv preprint
arXiv:2411.19588, 2024.
[31] Mohammad Asim, Christopher Wewer, Thomas Wimmer, Bernt
Schiele, Jan Eric Lenssen. MEt3R: Measuring Multi-View Consis-
tency in Generated Images. arXiv preprint arXiv:2501.06336, 2025.
[32] Shaohua Liu, Junzhe Lu, Zuoya Gu, Jiajun Li, Yue Deng. Aquatic-GS:
A Hybrid 3D Representation for Underwater Scenes. arXiv preprint
arXiv:2411.00239, 2024.
[33] Johannes L. Schönberger, Jan-Michael Frahm. Structure-from-
Motion Revisited. In Proceedings of the IEEE Conference on
Computer Vision and Pattern Recognition (CVPR) 2016: 4104-4113.
[34] Huapeng Li, Wenxuan Song, Tianao Xu, Alexandre Elsig, Jonas
Kulhanek. WaterSplatting: Fast Underwater 3D Scene Reconstruction
Using Gaussian Splatting. arXiv preprint arXiv:2408.08206, 2024.
[35] WZhou Wang, Alan C. Bovik, Hamid R. Sheikh, Eero P. Simoncelli.
Image quality assessment: from error visibility to structural similarity.
IEEE Transactions on Image Processing, 13(4): 600-612 (2004).
[36] Richard Zhang, Phillip Isola, Alexei A. Efros, Eli Shechtman,
Oliver Wang. The Unreasonable Effectiveness of Deep Features
as a Perceptual Metric. In Proceedings of the IEEE Conference on
Computer Vision and Pattern Recognition (CVPR) 2018: 586-595.
[37] Haoran Wang, Nantheera Anantrasirichai, Fan Zhang, David Bull.
UW-GS: Distractor-Aware 3D Gaussian Splatting for Enhanced
Underwater Scene Reconstruction. In Proceedings of the IEEE Winter
Conference on Applications of Computer Vision (WACV) 2025: 3280-
3289.
[38] Lihe Yang, Bingyi Kang, Zilong Huang, Xiaogang Xu, Jiashi Feng,
Hengshuang Zhao. Depth Anything: Unleashing the Power of Large-
Scale Unlabeled Data. In Proceedings of the IEEE/CVF Conference
on Computer Vision and Pattern Recognition (CVPR) 2024: 10371-
10381.
Li et al.: Preprint submitted to Elsevier
Page 12 of 12
