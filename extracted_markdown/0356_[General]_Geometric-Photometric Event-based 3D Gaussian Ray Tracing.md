<!-- page 1 -->
Geometric-Photometric Event-based 3D Gaussian Ray Tracing
Kai Kohyama 1, Yoshimitsu Aoki 1, Guillermo Gallego 2,3, Shintaro Shiba 1
1 Keio University, 2 Technische Universit¨at Berlin, 3 Einstein Center Digital Future,
Robotics Institute Germany, and Science of Intelligence Excellence Cluster, Germany,
Abstract
Event cameras offer a high temporal resolution over tra-
ditional frame-based cameras, which makes them suitable
for motion and structure estimation. However, it has been
unclear how event-based 3D Gaussian Splatting (3DGS)
approaches could leverage fine-grained temporal informa-
tion of sparse events. This work proposes a framework to
address the trade-off between accuracy and temporal res-
olution in event-based 3DGS. Our key idea is to decou-
ple the rendering into two branches: event-by-event ge-
ometry (depth) rendering and snapshot-based radiance (in-
tensity) rendering, by using ray-tracing and the image of
warped events. The extensive evaluation shows that our
method achieves state-of-the-art performance on the real-
world datasets and competitive performance on the syn-
thetic dataset.
Also, the proposed method works with-
out prior information (e.g., pretrained image reconstruction
models) or COLMAP-based initialization, is more flexible
in the event selection number, and achieves sharp recon-
struction on scene edges with fast training time. We hope
that this work deepens our understanding of the sparse na-
ture of events for 3D reconstruction. The code will be re-
leased.
1. Introduction
Event cameras have attracted increasing attention in com-
puter vision and robotics due to their advantages and capa-
bilities for various tasks [1, 2]. Unlike conventional cam-
eras that record synchronous frames at fixed time intervals,
event cameras respond asynchronously to per-pixel bright-
ness changes with µs resolution [3–5]. This working prin-
ciple makes them highly sensitive to motion, since changes
are due to scene contrast and relative motion.
In parallel, Gaussian Splatting (GS) [6] has emerged as
a state-of-the-art representation for photometric 3D recon-
struction and novel view synthesis (NVS). Since 3D struc-
ture and motion are tightly connected in the generation of
event data, it is paramount to develop 3DGS algorithms that
leverage the event camera’s fine-grained temporal informa-
Gaussians
!!"#
Rendered 
image
Instantaneous 
change
Warped 
events
Event-by-event (sparse)
Rendered frame (dense)
Warp (!!"#)
Continuous 
camera trajectory
Observed 
event stream
Depth-augmented 
events
GT
Ours
Figure 1.
Overview of the proposed method, which takes raw
events and poses as input. During the optimization of the 3D Gaus-
sians, rendering is decoupled into two pathways: event-by-event
(temporally dense) depth rendering and spatially dense intensity
rendering. We use the image of warped events to connect these
two pathways to compute both geometric and photometric losses.
The color results are from a synthetic dataset, and the monochrome
results are from two standard, real-world datasets.
tion. Also, thanks to the event camera’s minimal motion
blur and high dynamic range (DR), event-based GS meth-
ods have the potential to overcome some of the limitations
of frame-based GS, such as motion blur and low DR.
Previous approaches in event-based photometric 3D re-
construction (e.g., NeRF [7] and GS) typically perform two
dense renderings per sample (e.g., [8]).
The difference
between these two rendered images is compared with the
edge-like image obtained by pixel-wise aggregation of the
event data, resulting in a photometric loss that drives the
3D-Gaussian optimization [8, 9]. However, as this approach
requires dense (all-pixel) scene rendering twice, it not only
slows down the training, but also introduces a fundamen-
1
arXiv:2512.18640v1  [cs.CV]  21 Dec 2025

<!-- page 2 -->
tal limitation: the trade-off between accuracy and tempo-
ral window selection. A short time interval between the
two renderings fails to capture subtle intensity variations
that generate only a few events. Contrarily, a large interval
makes the predicted edge image blurry and discards fine-
grained temporal information in the observed edge. Similar
observations have been made in [10, 11]: a trade-off be-
tween capturing global lighting and local details.
In this work, we fundamentally address these limitations
and introduce the first framework for event-based GS that
renders the dense intensity (radiance) once per sample (i.e.,
a batch of events), while keeping the rendering efficient and
leveraging the high temporal resolution. Our key idea is to
consider dedicated structure and appearance updates in the
GS framework (Fig. 1). A “structure” pathway defines a
geometric loss built on top of Contrast Maximization [12]
by leveraging the known camera motion and the event-by-
event (i.e., sparse) rendered depth. An “appearance” path-
way defines a photometric loss between the instantaneous
brightness change modeled by the rendered dense intensity
and the change measured by the event data.
Our method showcases several advantages through ex-
tensive evaluations.
First, it does not rely on any prior
knowledge (e.g., frames or pretrained models for depth and
intensity) or COLMAP [13] for initialization. Second, it
achieves state-of-the-art rendering quality performance on
real-world datasets, where poses and raw events are noisy,
with fast training time (it is faster than the latest methods
that we benchmark [8, 9, 14]). Third, it shows robustness
with respect to the number of events processed per sample,
without compromising accuracy.
In summary, this work presents several distinctive con-
tributions in event-only Gaussian Splatting:
1. The proposed method decouples two different quantities
in 3DGS rendering: the continuous-time spatially sparse
depth, and the instantaneous dense intensity. It addresses
the trade-off between accuracy and temporal resolution
in existing event-based 3D reconstruction methods.
2. The comprehensive evaluation shows state-of-the-art re-
sults on real-world datasets and competitive results in
simulation without relying on any prior knowledge, as
opposed to existing event-based 3DGS methods.
3. The proposed framework connects event-by-event depth
estimation and 3DGS, which is enabled by an efficient
event-by-event ray-tracing implementation.
4. The method achieves the fastest training time among
other tested state-of-the-art methods (e.g., [8, 9, 14]).
We hope that this work unblocks the potential of high tem-
poral resolution event data in 3D reconstruction.
2. Related Work
3D Gaussian Splatting (3DGS) [6] represents the scene
as a collection of anisotropic Gaussian ellipsoids and ren-
ders via differentiable splatting [6]. These methods achieve
high-fidelity NVS with faster rendering and more scalable
training in static and dynamic scenes [15–17] than Neu-
ral Radiance Fields (NeRFs) [7]. While most works fo-
cus on rasterization-based splatting, recently, ray-tracing
approaches have emerged, which inspire our work.
No-
tably, 3D Gaussian Ray Tracing (3DGRT) [18] casts rays
against volumetric Gaussian particles, and 3DGUT [19] re-
places Elliptical weighted-average raster splatting with an
Unscented Transform projection of Gaussian particles.
Event cameras have inspired substantial work in recon-
structing 3D geometry and scene appearance, leveraging
motion information from their data modality of high tempo-
ral resolution. Several approaches propose enhanced frame-
based NVS aided by the complementary information in the
event data, e.g., in the presence of fast motion (images with
motion blur) or deformations [11, 20–23]. Such approaches
may still suffer from bottlenecks of the frame-based cam-
eras in the system, such as low DR, and inaccuracies in sen-
sor fusion calibration. Instead, event-only methods like our
work focus on unlocking the potential of event cameras.
The key question of event-based NVS methods (NeRF
and GS) lies in the measurement model: how to compare
the modeled scenes, which typically display absolute in-
tensity rendered at concrete viewpoints and times, to the
acquired event data stream, which measures sparse inten-
sity differences asynchronously at a quasi-continuous col-
lection of times and viewpoints. They seem opposites. The
typical approach in the literature consists in accumulating
events into an image (of intensity increments) and comput-
ing the photometric error with respect to the difference be-
tween two rendered frames at the first and last event times-
tamps. While many event NeRF methods (e.g., [10, 24–26])
and GS methods (e.g., [11, 27–29]) follow such philoso-
phy, they face the trade-off between accuracy and temporal
window selection. Instead of rendering dense images, per-
event loss computation has been proposed in event-NeRF
[14, 30, 31] based on ray-tracing, leveraging event genera-
tion models to directly compare each observed event. How-
ever, these NeRF methods tend to suffer from considerable
event noise in real-world cameras and slow rendering.
Notably, most existing works in event-based GS uti-
lize some prior knowledge. For example, Elite-EvGS [27]
utilizes pretrained event-to-video models for initialization
and regularization.
Event-3DGS [32], which jointly es-
timates sensor parameters for better photometric recon-
struction, also uses video reconstruction for initialization.
IncEventGS [9], which is conceived as an incremental
tracking and mapping system (and therefore does not need
camera pose information), uses a depth-pretrained model
for bootstrapping. E-3DGS [33] uses an additional piece
of data to better recover absolute intensity: exposure events
obtained by controlling the camera’s aperture.
2

<!-- page 3 -->
IWE(!!"#)
Diff-image (!!"#)
Gaussians
Event-by-event
Flow {# $$, !% }
Event-by-event 
Depth {' $$, !% }
Interpolated poses
! " , $ "
"! ≦" ≦""}
ℰ= {(+, ", ,)|"! ≦" ≦""}
Raw events
Rendered image (&!"# $
Spatially sparse & Temporally dense
Dense Flow #&!"# $
Dense Depth '&!"# $
Spatially dense & Temporally sparse (once)
/0 ≈−∇4 5 6
6
Ray-tracing 
rendering
Geometric 
loss ℒ'
Photometric 
loss ℒ(, ℒ)
Warp
Camera parameters
" = "#$%
Figure 2. Method overview. Using ray-tracing renderer, we estimate depth for each event and compute the flow with the interpolated poses
(i.e., motion field). Performing event warping produces the image of warped events at tmid and computes the contrast loss. We render the
dense intensity (radiance) at tmid and compute the instantaneous brightness increment image, which we use for the photometric loss.
Our work falls into the category of event-only 3DGS
methods, such as Event-3DGS [32] and EventSplat [8],
however, with several significant differences: (i) earlier
work utilize prior knowledge (e.g., the pretrained E2VID
model [34]) for initial intensity recovery or initial 3D Gaus-
sians [9], while ours does not or rely on any prior knowl-
edge, and (ii) we explicitly incorporate geometric and pho-
tometric loss terms in the proposed render-once framework,
which improve robustness with respect to the choice of the
number of events processed, as opposed to using a multi-
window optimization scheme in a two-rendering pipeline
[8, 10]. The idea of using event warping is concurrently
proposed in PAEv3D [25] (NeRF) and EF-3DGS [35] (GS
using both events and frames), however, none of them tackle
event-only GS or realize per-event depth rendering.
3. Methodology
The overview of our framework is shown in Figure 2. The
scene is modeled via 3D Gaussians (Sec. 3.1) compris-
ing structure and appearance parameters that interact with
the event data through the optimization of a weighted loss
function. The loss combines a geometric term that mea-
sures the goodness of fit between the event data and the
modeled apparent motion, and appearance / photometric
terms that measure the goodness of fit between the events
and the brightness increment predicted by the 3D Gaus-
sian scene model. Accordingly, we propose to decouple the
processing in two branches: an event-by-event (i.e., spa-
tially sparse but temporally dense) scene rendering of the
unknown depth for geometric loss computation (Secs. 3.2
and 3.3) and a snapshot-based (i.e., spatially dense but tem-
porally sparse) rendering for the photometric loss (Sec. 3.4).
We use the image of warped events (IWE) [12] to connect
both branches.
3.1. 3D Gaussian Splatting
In the typical 3D Gaussian Splatting (3DGS) setting [6], a
static scene is represented as a set of Ng Gaussians G =
{(µi, Σi, ci, αi)}Ng
i=1, where µi ∈R3 denotes the 3D mean
position, Σi ∈R3×3 the covariance matrix encoding the
anisotropic spatial extent, ci ∈R3 the color and αi ∈[0, 1]
the opacity. Each Gaussian defines a density function in
space: Gi(X; µi, Σi) .= e−1
2 (X−µi)⊤Σ−1
i
(X−µi). The ren-
dered appearance is obtained by projecting these 3D Gaus-
sians into the image plane and blending their contributions
according to visibility and opacity.
Projected Gaussians
are at pixel locations µ′
i = π(µi) and with covariances
Σ′
i ≈JiΣiJ⊤
i , where Ji = ∂π(X)
∂X

X=µi is the Jacobian of
the projection function π : R3 →R2 that maps world coor-
dinates to pixel coordinates. The contribution of each Gaus-
sian to a pixel x is then given by: wi(x) = αiGi(x; µ′
i, Σ′
i).
The rendered color for each pixel C(x) is approximated
by alpha compositing along the camera ray with correct or-
3

<!-- page 4 -->
dering and blending based on depth:
C(x) = PN
i=1 ci wi(x) Qi−1
j=1(1 −wj(x)).
(1)
Finally, to obtain a differentiable depth rendering, we as-
sociate each Gaussian with a mean depth value Zi = e⊤
3 µi
in camera coordinates. The rendered depth D(x) is then
given by the opacity-weighted expectation:
D(x) =
PN
i=1 Zi wi(x) Q
j<i(1 −wj(x))
PN
i=1 wi(x) Q
j<i(1 −wj(x)) + ϵ
.
(2)
3.2. Event-by-event Ray Tracing
An event camera asynchronously captures visual changes as
soon as the log-intensity L at a pixel x exceeds a threshold
Cth: ∆L(xk, tk) .= L(xk, tk) −L(xk, tk −∆tk) = pk Cth.
Each event ek .= (xk, tk, pk) specifies the space-time coor-
dinates (xk, tk) and polarity pk ∈{+1, −1} of the change.
Events are sparse in pixel space and quasi-continuous
(dense) in time. To fully leverage sparsity, the rendering of
the 3DGS should be sparse rather than image rasterization.
Hence, we propose the framework of event-by-event ren-
dering in the 3DGS pipeline, inspired by recent advances
in ray-tracing GS [18, 19]. The idea that each event should
also carry information about depth, i.e., depth-augmented
events, originates in [36] for the context of SLAM.
For each event ek, we render the corresponding depth
D(xk, tk), which is now a function of both space and time.
To this end, at each timestamp tk, we compute the inter-
polated camera pose (R(tk), T(tk)) and the ray through
the camera’s optical center and pixel xk. Finally, GPU-
accelerated ray tracing enables us to efficiently render
event-by-event depth D .= {D(xk, tk)}Ne
k=1, as illustrated
in Fig. 3, column (b).
Assuming a stationary scene viewed by a moving camera
with linear and angular velocities V and ω, respectively,
the per-event depth D(x, t) can be used to compute the per-
event apparent motion via the motion field equation [37]:
v(x, t) =
1
D(x, t)A(x)V + B(x)ω.
(3)
See the example in Fig. 3, column (d).
3.3. Geometric Loss
To guide the estimation of the 3DGS parameters, we con-
sider a geometric loss that is computed in an unsuper-
vised manner following the Contrast Maximization (CMax)
framework [12] that is widely used for various motion es-
timation tasks [38–45].
Under the brightness constancy
assumption, events E
.= {ek}Ne
k=1 are caused by moving
edges and can be motion-compensated by a warping op-
eration if their motion is known: E′
tref
.= {e′
k}Ne
k=1, where
e′
k
.= (x′
k, tref, pk), at a reference time tref. We formulate
(a) Dense depth
(b) Sparse depth
(c) Dense flow
(d) Sparse flow
Figure 3. Visualization of dense/sparse depth and optical flow.
Sparse depth and optical flow are not simply obtained by masking
the dense counterparts, but by actual event-by-event ray tracing
(Sec. 3.2). Top: using real events (EDS). Bottom: using synthetic
events. The flow color notation is specified in Fig. 2.
the warp using the spatio-temporal optical flow v(x, t) [46],
which in the 3DGS setting can be obtained using (3),
x′
k = xk + (tk −tref) v(xk, tk).
(4)
Then, the warped events are aggregated to produce an image
or histogram of warped events (IWE, top branch of Fig. 2)
IWE(x; tref, D) .= PNe
k=1 bkCthδ(x −x′
k),
(5)
where bk = pk if polarity is used and bk = 1 if polarity is
not used. The Dirac delta is approximated by a Gaussian,
δ(x −µ) ≈N(x; µ, σ2 = 1px).
The IWE measures the alignment between the event data
and the candidate motion v. The true motion v∗leads to
a sharp IWE, with motion-compensated edges. Hence, as
geometric loss we use the IWE sharpness (without polarity,
bk = 1), normalized by the value at zero flow [46]:
Lc .= G(0; −) / G(v(D); tref),
G(v(D); tref) =
1
|Ω|
R
Ω∥∇IWE(x; tref, D)∥1dx.
(6)
Notice that we use the reciprocal of the contrast objective
due to the minimization formulation, and the L1-norm be-
cause it performs well for depth estimation [47].
3.4. Photometric Loss
The IWE (5) represents not only motion-corrected edges,
but also their strength (e.g., intensity gradient) with respect
to the flow direction [12, 50]. Hence, we may use the IWE
to design not only geometric loss terms but also photomet-
ric ones (bottom branch of Fig. 2, and examples in Fig. 3
columns (a), (c)). This is inspired by methods in the lit-
erature that define losses on brightness increment images
obtained from grayscale information [48, 51–53].
Specifically, following the event generation model [1],
the prediction of the scene’s edge strength at time tref is:
ˆI(x; tref) .= −∇C · v/∥v∥,
(7)
4

<!-- page 5 -->
EDS 07
EDS 11
EDS 13
TUM 1d-trans
TUM desk2
(a) E2VID + 3DGS
(b) IncEventGS [9]
(c) Robust E-NeRF [14]
(d) EventSplat [8]
(e) Ours
(f) GT
Figure 4. Results on the real-world datasets EDS [48] and TUM-VIE [49]. The event camera’s field of view in the TUM dataset is narrower
than the GT (i.e., frame camera) in the vertical direction.
where C ≡C(x) is the rendered frame (1) from the view-
point of camera pose (R(tref), T(tref)) and v ≡v(x, tref)
is the motion field (3) obtained using the rendered depth at
time tref (bottom branch of Fig. 2). This corresponds to the
instantaneous rate of brightness change in the optical flow
direction [50]. Note that C may represent color for the sim-
ulated/color event cameras, or gray (intensity) for the stan-
dard event cameras. The dense-pixel (i.e., radiance) render-
ing happens once in each optimization step (see Sec. 5.1).
Finally, photometric errors between the IWE (with bk =
pk) and its prediction (7) are defined by the L2-norm and
the Structural Similarity Index Measure (SSIM) [54]:
Lp .= 1
|Ω|∥IWE(x; tref) −ˆI(x; tref)∥2,
Ls .= SSIM
 IWE(x; tref), ˆI(x; tref)

.
(8)
We find that warping is more useful to leverage the high
temporal resolution than the simple pixel-wise accumula-
tion of polarities used in most event-based GS and NeRF lit-
erature ([8–10]), because the latter: (i) may result in blurry
edge images that discard the fine temporal resolution, (ii)
incurs neutralization (cancellation of event polarities), (iii)
requires two dense intensity renderings to compute the pho-
tometric loss, (iv) omits a dependency on the unknown
depth/flow that can be useful during optimization [45].
3.5. Combined Loss Function
For each slice of events E we use the middle timestamp as a
reference, tref .= tmid. The total loss is a weighted sum of the
event-alignment loss (CMax) and the photometric losses:
L .= λcLc + λpLp + λsLs.
(9)
3.6. Initialization
The initialization of the 3D Gaussians is important. For ex-
ample, it is common practice for frame-based GS methods
to use COLMAP [13] to favor initial Gaussians on scene
5

<!-- page 6 -->
EDS [48]
TUM-VIE [49]
Metric
Method
Avg.
03
07
08
11
13
Avg.
1d-trans
desk2
PSNR ↑
E2VID + 3DGS
15.510
15.670
15.050
14.030
13.830
18.960
9.524
9.382
9.664
Robust E-NeRF (ICCV’23) [14]
16.250
19.190
14.780
14.750
14.430
18.100
11.790
9.612
13.970
IncEventGS (CVPR’25) [9]
15.210
14.130
15.760
15.890
13.830
16.460
10.090
10.130
10.050
EventSplat (CVPR’25) [8]
18.860
20.780
19.140
17.530
17.790
19.050
–
–
–
Ours
19.470
19.040
20.240
21.030
16.730
20.300
13.090
11.970
14.200
SSIM ↑
E2VID + 3DGS
0.692
0.716
0.689
0.642
0.691
0.723
0.516
0.525
0.507
Robust E-NeRF (ICCV’23) [14]
0.739
0.846
0.815
0.735
0.569
0.729
0.573
0.504
0.642
IncEventGS (CVPR’25) [9]
0.691
0.756
0.684
0.692
0.648
0.676
0.533
0.536
0.529
EventSplat (CVPR’25) [8]
0.792
0.835
0.816
0.745
0.789
0.774
–
–
–
Ours
0.816
0.819
0.855
0.814
0.790
0.804
0.716
0.665
0.766
LPIPS ↓
E2VID + 3DGS
0.375
0.266
0.378
0.402
0.415
0.415
0.759
0.790
0.728
Robust E-NeRF (ICCV’23) [14]
0.543
0.324
0.476
0.567
0.700
0.650
0.588
0.721
0.454
IncEventGS (CVPR’25) [9]
0.561
0.356
0.557
0.631
0.588
0.674
0.685
0.707
0.663
EventSplat (CVPR’25) [8]
0.362
0.239
0.351
0.424
0.391
0.407
–
–
–
Ours
0.357
0.272
0.335
0.369
0.396
0.414
0.411
0.497
0.324
Table 1. Results on standard, real-world datasets EDS and TUM-VIE. Best in bold.
texture and edges. Indeed, prior work EventSplat [8] uses
intensity reconstruction and runs COLMAP for initializa-
tion. However, it relies on the pretrained E2VID model [34]
as prior. In this work, we propose using the IWE(x; tmid)
without polarity and the rendered image C(x) for initial-
ization, keeping the rest of the pipeline untouched. This
favors initial 3D Gaussians around scene structures because
the IWE responds to edges. We find that IWEs produce bet-
ter initialization than images of pixel-wise accumulation of
event polarities because of their sharpness, which narrows
down the initial possible locations of the Gaussian centers.
4. Experiments
4.1. Datasets, Metrics, and Baselines
Datasets. We use standard datasets for event-based NeRF
and GS works, both on simulated and real data. EDS [48]
is a real-world dataset of indoor scenarios, recorded with
a VGA event camera (640 × 480 px), an RGB camera, an
IMU, and ground-truth poses from motion capture. The se-
quences include challenging scenes, such as flickering light
sources. TUM-VIE [49] is another real-world dataset, ac-
quired with an HD event camera (1280 × 720 px, i.e., 1
megapixel) and with ground-truth poses. It consists of in-
door and outdoor sequences recorded with the sensor rig
mounted on a helmet. We use indoor sequences follow-
ing prior work. Robust E-NeRF [14] contributes a synthetic
color event dataset with a 800×800 px resolution and color
pixels following the Bayer pattern.
Evaluation Metrics. Following prior work [8, 14], re-
construction performance is measured with standard met-
rics on view synthesis quality: Peak Signal-to-Noise Ratio
(PSNR), SSIM, and Learned Perceptual Image Patch Sim-
ilarity (LPIPS). Real-world datasets use poses from colo-
cated frame-based cameras for the evaluation of rendering.
In addition, we follow prior work and apply gamma correc-
tion before computing the evaluation metrics.
Baselines. Our baselines are among the best event-only
NeRF and GS methods in the literature. First, we use the
two-stage approach of E2VID image reconstruction [34]
and frame-based GS, termed “E2VID + 3DGS”. For event-
based GS methods (the two-rendering approaches), we re-
train IncEventGS [9], and copy the results from EventSplat
[8] because it has no available code. We also compare with
the state-of-the-art NeRF method Robust E-NeRF [14] that
uses event-by-event loss computation.
Hyper-parameters.
For all sequences the contrast
threshold is set to Cth = 0.25. The loss weights in (9)
are set to λc = 0.125, λp = 500, λs = 1. The number of
events is Ne = 125k for EDS and synthetic data [14], and
Ne = 500k for TUM-VIE. We further test the robustness of
the method to the choice of Ne. The initialization steps are
10k, and the entire training steps are 40k for all sequences.
4.2. Results on Real-World Datasets
Figure 4 shows the results on EDS and TUM-VIE datasets.
Throughout the scenes, the proposed method consistently
achieves successful reconstructions (we encourage readers
to watch the video). Notably, our reconstructions recover
fine details: (i) gradual (mild) intensity changes, e.g., shad-
ows and reflections on the desk in TUM-desk2, (ii) fewer
artifacts due to noisy events, e.g., walls on EDS-07,11.
(iii) sharp edges in details, e.g., airplane and background
in EDS-13. Also, EDS sequences contain lots of events
6

<!-- page 7 -->
Chair
Drums
Materials
(a) E2VID + 3DGS
(b) Robust E-NeRF [14]
(c) EventSplat [8]
(d) Ours
(e) GT
Figure 5. Qualitative results on the color synthetic dataset [14].
Metric
Method
Avg.
Chair
Drums
Ficus
Hotdog
Lego
Materials
Mic
PSNR ↑
E2VID + 3DGS
19.290
21.390
19.860
19.900
15.550
18.170
20.080
20.100
Robust E-NeRF (ICCV’23) [14]
28.190
30.240
23.150
30.710
18.070
27.340
24.980
32.870
EventSplat (CVPR’25) [8]
28.140
28.690
25.810
29.900
22.910
29.220
27.160
33.270
Ours
23.110
26.420
23.340
25.360
17.760
18.080
23.500
27.300
SSIM ↑
E2VID + 3DGS
0.917
0.934
0.915
0.922
0.897
0.895
0.901
0.957
Robust E-NeRF (ICCV’23) [14]
0.945
0.958
0.897
0.971
0.953
0.934
0.923
0.981
EventSplat (CVPR’25) [8]
0.953
0.953
0.947
0.966
0.940
0.945
0.936
0.986
Ours
0.927
0.941
0.921
0.938
0.911
0.901
0.910
0.968
LPIPS ↓
E2VID + 3DGS
0.118
0.076
0.094
0.108
0.208
0.145
0.125
0.069
Robust E-NeRF (ICCV’23) [14]
0.057
0.040
0.091
0.022
0.095
0.074
0.052
0.029
EventSplat (CVPR’25) [8]
0.051
0.047
0.052
0.028
0.098
0.055
0.060
0.015
Ours
0.074
0.054
0.066
0.046
0.160
0.097
0.061
0.032
Table 2. Quantitative results on the color synthetic dataset [14]. The Bayer pattern is challenging for the proposed warp-based method.
due to flickering lights. Surprisingly, our method converges
and successfully reconstructs the scene while relying on the
contrast loss, which may be sensitive to flickering events.
The quantitative comparison is reported in Tab. 1. Our
method consistently achieves state-of-the-art results: the
best results on average across all three metrics, despite not
relying on pretrained depth estimation models [9], or video-
guided initialization and cubic splines for pose interpolation
[8]. Notice that there are some limitations of the quantita-
tive evaluation on the real-world sequences, such as the high
dynamic range (HDR) of event cameras, and the disparity
between the event camera and the frame camera.
4.3. Results on Synthetic Data
Due to the influence of synthetic RGB-based novel-view-
synthesis datasets [7], the method is also tested on such
data, converted into events via an event camera simulator
[55]. Note that such sequences are unrealistic because they
lack the noise and most dynamic effects characteristic of
event cameras.
Results are shown in Fig. 5.
The RGB
Bayer pattern is challenging for warp-based methods, such
as the proposed one, since (i) warped pixels may not fall
into the same location among different colors [50], which
complicates the demosaicing operation, and (ii) the color
7

<!-- page 8 -->
distribution is imbalanced (green pixels are twice as many
as red/blue). Nonetheless, our method achieves successful
color reconstruction. Following the same color correction
steps as [8, 14], our results show fewer object artifacts and
fewer floaters on the background. Quantitative results are
given in Tab. 2, where we achieve competitive values.
Figure 3 shows rendered depth (sparse or dense) ob-
tained on this data and real-world data.
We find that
Gaussian-based depth estimation achieves high-quality re-
sults, especially around occlusions. We report the quantita-
tive comparisons with EMVS [56] in the supplementary.
4.4. Runtime
The training takes 30–45 minutes for EDS and synthetic se-
quences [14], and 80–130 minutes for TUM-VIE. The ren-
dering takes roughly 3 ms for Ng = 0.1M, and 30 ms
for Ng = 1M, using a PyTorch implementation on an
NVIDIA RTX6000 (Ada).
Our method is significantly
faster than other methods: both Robust E-NeRF [14] and
IncEventGs [9] take 3 h to train on EDS under the same set-
tings. EventSplat [8] does not have publicly available code
but reports 1–3 h for the same number of iterations on EDS.
5. Ablations
5.1. Effect of Temporal Window Selection
We further investigate the efficacy of our two-branch
pipeline, which renders intensity just once (Fig. 2). Most
event-based GS methods render dense intensity twice and
subtract one from another to obtain an edge-like image (i.e.,
∆C = C(t2) −C(t1)) that is compared to the brightness
increment obtained by pixel-wise accumulation of the event
data. A clear advantage of the proposed pipeline over the
above “render-twice” pipeline is the robustness with respect
to the choice of Ne. Figure 6 reports reconstruction per-
formance for different Ne, using two sequences from the
TUM-VIE dataset: 1d-trans and desk2. For larger Ne the
edges become more blurry in the render-twice pipeline, and
therefore, the reconstruction quality degrades. However, the
proposed render-once pipeline shows consistent results re-
gardless of Ne, which is desirable because it is a sensible
parameter that depends on many factors, such as camera
resolution, scene texture, and camera motion.
5.2. Contrast Loss and Initialization
We conduct ablation studies on the contrast loss and ini-
tialization, as shown in Tab. 3. Here, “w/o initialization”
starts from random 105 Gaussians and skips the proposed
initialization step (Sec. 3.6). Our method achieves the best
or second-best results among all metrics and datasets. No-
tably, the SSIM improves with the contrast loss, showcasing
the efficacy of the proposed ray-tracing rendering and loss.
PSNR
SSIM
Ours (Render once)
Render twice
Number of events
Number of events
Figure 6. Robustness with respect to the time window selection.
We compare the proposed pipeline and its render-twice variant for
different numbers of events Ne. Due to the warp that reduces blur
in the scene, the proposed method shows robustness against the
choice of Ne, achieving consistently good values.
Metric
Method
Synthetic [14]
EDS
TUM-VIE
PSNR ↑
Ours
23.110
19.470
13.090
w/o contrast loss
9.600
15.520
13.450
w/o initialization
20.820
17.340
11.360
SSIM ↑
Ours
0.927
0.816
0.716
w/o contrast loss
0.810
0.744
0.715
w/o initialization
0.908
0.759
0.633
LPIPS ↓
Ours
0.073
0.357
0.411
w/o contrast loss
0.405
0.581
0.405
w/o initialization
0.121
0.442
0.561
Table 3. Ablation on the contrast loss and the initialization.
6. Limitations
Our method follows an unsupervised approach based on
the contrast loss, which assumes brightness constancy and
therefore suffers in the presence of flickering events. Al-
though the pipeline converges on the EDS dataset, we find
that the presence of large amounts of flickering events make
appearance recovery and depth estimation results unstable.
The proposed framework assumes static scenes, and is
not expected to work well on dynamic scenes. However,
following recent advances in frame-based 4D GS [16, 57],
event-based 4D GS would be a relevant future direction.
7. Conclusion
We propose the first framework for event-based Gaussian
Splatting that fully leverages the spatio-temporal properties
of event data. Our rendering pipeline consists of two ex-
plicit pathways: spatially sparse and temporally dense (i.e.,
event-by-event) pathway for geometry (depth) recovery, and
spatially dense and temporally sparse (i.e., a snapshot) path-
way for appearance (radiance) estimation. A thorough eval-
uation reveals that the proposed method (i) achieves state-
of-the-art performance on real-world data without using ex-
tra priors, and (ii) effectively tackles the trade-off revolved
around the choice of the number of events to process.
8

<!-- page 9 -->
8. Acknowledgments
We thank Mr. Yura Toshiya for useful discussions. Funded
by the Deutsche Forschungsgemeinschaft (DFG, German
Research Foundation) under Germany’s Excellence Strat-
egy – EXC 2002/1 “Science of Intelligence” – project num-
ber 390523135.
This work has been partially supported
by the German Federal Ministry of Research, Technology
and Space (BMFTR) under the Robotics Institute Germany
(RIG).
9. Supplementary
In the supplementary, we first report the sensitivity analy-
sis of the loss weights (Sec. 9.2), and the detailed analysis
of the runtime (Sec. 9.3). Then, we discuss the proposed
initialization method with existing work on event-based
structure-from-motion (SfM) (Sec. 9.4). Finally, more re-
sults are provided on dense/sparse depth, flow, and rendered
intensity (Sec. 9.5).
9.1. Video
We encourage readers to inspect the attached video, which
summarizes the method and the results.
9.2. Sensitivity Analysis
Table 4 reports the sensitivity analysis regarding the loss
weights: Lc, Lp, using the EDS dataset. The metrics are
averaged over all five sequences. The results confirm the
efficacy of all proposed loss terms in leading to a successful
convergence of the GS model.
Notably, we find that event collapse (e.g., [58]) occurs
with a large weight of the Contrast loss Lc. The collapse is
observed in Fig. 7c) as corrupted depth (many small Gaus-
sians with various distances). In Fig. 7b) IWE, the lamp on
the desk shows undesired local optima of the warp.
9.3. Runtime per each training step
In Sec. 4.4, we report the training runtime for the total steps
to converge. Here, we provide a detailed runtime analysis
of each step in Fig. 8. Larger scenes have more Gaussians
(i.e., larger Ng). The runtime of the proposed method scales
sub-linearly with the scene size, despite having the warp
(i.e., O(Ne)) and IWE (i.e., O(Ne + Np)) creation steps.
For reference, we also report the render-twice variant of the
proposed pipeline. Our pipeline is slightly faster; however,
we do not observe any significant differences.
9.4. Comparison with SfM methods
As discussed in Sec. 3.6, the proposed framework initializes
the scene geometry via optimization without polarity infor-
mation, which has a similar effect as COLMAP, i.e., SfM.
Here, using the synthetic dataset from [14], which has accu-
rate ground truth geometry, we now visualize and compare
λc
λs
PSNR ↑SSIM ↑LPIPS ↓
0.1 0.1
18.994
0.801
0.389
0.1 1
19.584
0.812
0.359
0.1 10
17.282
0.773
0.423
1
0.1
18.432
0.790
0.398
1
1
19.094
0.805
0.361
1
10
18.593
0.802
0.359
10
0.1
16.666
0.753
0.448
10
1
16.288
0.752
0.436
10
10
16.946
0.770
0.398
Table 4. Sensitivity analysis of the loss weights.
(a) Raw events
(b) IWE (collapsed)
(c) Depth (corrupted)
(d) Rendered intensity
Figure 7. Examples of corrupted depth for large Lc.
initial point cloud estimation results. For the evaluation of
3D points, we use the Chamfer Distance (CD):
CD(X, ˆX) = 1
|X|
X
x∈X
min
ˆx∈ˆ
X
∥x −ˆx∥2
2
+
1
| ˆX|
X
ˆx∈ˆ
X
min
x∈X ∥x −ˆx∥2
2,
(10)
which measures the 3D Euclidean distance between the pre-
dicted points ˆX and the ground truth (GT) points X.
Figure 9 displays qualitative 3D point estimation re-
sults.
As baselines, we use the frame-based pipeline
(“E2VID [34] + VGGT [59]”) and Event-based Multi-view
Stereo (EMVS) [56]. Our method consistently recovers fine
details of the scene, such as the thin edges of the chair and
drum, and the cables of the mic. On the other hand, the
event-based baseline, EMVS [56], struggles to recover the
entire scene and is limited to the points visible from a small
range of viewpoints in the entire trajectory. EMVS is not
suitable for the 360-degree trajectory that is typical for the
GS and NeRF settings, since the 3D space is represented as
9

<!-- page 10 -->
Method
CD ↓(Avg.)
Chair
Drums
Ficus
Hotdog
Lego
Materials
Mic
E2VID [34] + VGGT [59]
34.820
25.310
82.340
–
5.284
4.568
11.500
79.920
EMVS [56]
35.090
9.757
79.330
7.260
51.530
71.390
18.890
7.490
Ours
3.559
3.127
1.204
0.949
11.490
3.056
1.351
3.734
Table 5. Quantitative results on point cloud estimation using data [14]. The CD is given in mm. “E2VID + VGGT” does not converge on
the ficus sequence.
Figure 8. Detailed analysis on the runtime for different Ng.
voxels (DSIs) with the perspective projection.
Quantitative results are reported in Table 5. Our method
achieves the smallest CD among all sequences except for
the hotdog sequence. “E2VID + VGGT” recovers the hot-
dog sequence the best, possibly due to its simple shape;
however, it struggles to estimate correct 3D points for other
sequences. The overall results show that the proposed ini-
tialization provides more plausible initial geometry than the
conventional event-based or event-to-frame SfM methods.
9.5. Further Qualitative Results
Figure 10 shows further results on depth, flow, and intensity
reconstruction using the three datasets.
10

<!-- page 11 -->
Chair
Drums
Materials
Mic
E2VID + VGGT
EMVS
Ours
GT
Figure 9. Results on the point cloud estimation. For comparison, we use E2VID [34] + VGGT [59] and EMVS [56].
11

<!-- page 12 -->
(a) Dense depth
(b) Sparse depth
(c) Dense flow
(d) Sparse flow
(e) Rendered intensity
(f) GT
Figure 10. Additional depth, flow and intensity reconstruction results on EDS (rows 1 and 2), TUM-VIE (row 3) and color synthetic
datasets (rows 4 and 5).
12

<!-- page 13 -->
References
[1] Guillermo Gallego, Tobi Delbruck, Garrick Orchard, Chiara
Bartolozzi, Brian Taba, Andrea Censi, Stefan Leutenegger,
Andrew Davison, J¨org Conradt, Kostas Daniilidis, and Da-
vide Scaramuzza, “Event-based vision: A survey,” IEEE
Trans. Pattern Anal. Mach. Intell., vol. 44, no. 1, pp. 154–
180, 2022.
[2] Hadi AliAkbarpour, Ahmad Moori, Javad Khorramdel, Erik
Blasch, and Omar Tahri, “Emerging trends and applications
of neuromorphic dynamic vision sensors: A survey,” IEEE
Sensors Reviews, vol. 1, p. 14–63, 2024.
[3] Patrick Lichtsteiner, Christoph Posch, and Tobi Delbruck,
“A 128×128 120 dB 15 µs latency asynchronous temporal
contrast vision sensor,” IEEE J. Solid-State Circuits, vol. 43,
no. 2, pp. 566–576, 2008.
[4] Christoph Posch, Teresa Serrano-Gotarredona, Bernabe
Linares-Barranco,
and Tobi Delbruck,
“Retinomorphic
event-based vision sensors: Bioinspired cameras with spik-
ing output,” Proc. IEEE, vol. 102, pp. 1470–1484, Oct. 2014.
[5] Thomas Finateu, Atsumi Niwa, Daniel Matolin, Koya
Tsuchimoto, Andrea Mascheroni, Etienne Reynaud, Poo-
ria Mostafalu, Frederick Brady, Ludovic Chotard, Florian
LeGoff, Hirotsugu Takahashi, Hayato Wakabayashi, Yusuke
Oike, and Christoph Posch, “A 1280x720 back-illuminated
stacked temporal contrast event-based vision sensor with
4.86µm pixels, 1.066Geps readout, programmable event-
rate controller and compressive data-formatting pipeline,” in
IEEE Int. Solid-State Circuits Conf. (ISSCC), pp. 112–114,
2020.
[6] Bernhard Kerbl, Georgios Kopanas, Thomas Leimk¨uhler,
and George Drettakis, “3D Gaussian splatting for real-time
radiance field rendering,” ACM Trans. Graph., vol. 42, July
2023.
[7] Ben Mildenhall, Pratul P. Srinivasan, Matthew Tancik,
Jonathan T. Barron, Ravi Ramamoorthi, and Ren Ng,
“NeRF: representing scenes as neural radiance fields for
view synthesis,” Commun. ACM, vol. 65, p. 99–106, Dec.
2021.
[8] Toshiya Yura, Ashkan Mirzaei, and Igor Gilitschenski,
“EventSplat: 3D Gaussian splatting from moving event cam-
eras for real-time rendering,” in IEEE Conf. Comput. Vis.
Pattern Recog. (CVPR), pp. 26876–26886, 2025.
[9] Jian Huang, Chengrui Dong, Xuanhua Chen, and Peidong
Liu, “IncEventGS: Pose-free gaussian splatting from a single
event camera,” in IEEE Conf. Comput. Vis. Pattern Recog.
(CVPR), pp. 26933–26942, 2025.
[10] Viktor Rudnev, Mohamed Elgharib, Christian Theobalt, and
Vladislav Golyanik, “EventNeRF: Neural radiance fields
from a single colour event camera,” in IEEE Conf. Comput.
Vis. Pattern Recog. (CVPR), pp. 4992–5002, 2023.
[11] Tianyi Xiong, Jiayi Wu, Botao He, Cornelia Fermuller, Yian-
nis Aloimonos, Heng Huang, and Christopher A Metzler,
“Event3DGS: Event-based 3D Gaussian splatting for high-
speed robot egomotion,” Conf. on Robot Learning (CoRL),
2024.
[12] Guillermo Gallego, Henri Rebecq, and Davide Scaramuzza,
“A unifying contrast maximization framework for event cam-
eras, with applications to motion, depth, and optical flow
estimation,” in IEEE Conf. Comput. Vis. Pattern Recog.
(CVPR), pp. 3867–3876, 2018.
[13] Johannes
Lutz
Sch¨onberger
and
Jan-Michael
Frahm,
“Structure-from-motion revisited,” in IEEE Conf. Comput.
Vis. Pattern Recog. (CVPR), 2016.
[14] Weng Fei Low and Gim Hee Lee, “Robust e-NeRF: NeRF
from sparse & noisy events under non-uniform motion,” in
Int. Conf. Comput. Vis. (ICCV), pp. 18289–18300, 2023.
[15] Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger, and
Shenghua Gao, “2D Gaussian splatting for geometrically ac-
curate radiance fields,” in SIGGRAPH, pp. 1–11, 2024.
[16] Guanjun Wu, Taoran Yi, Jiemin Fang, Lingxi Xie, Xiaopeng
Zhang, Wei Wei, Wenyu Liu, Qi Tian, and Xinggang Wang,
“4D Gaussian splatting for real-time dynamic scene render-
ing,” in IEEE Conf. Comput. Vis. Pattern Recog. (CVPR),
pp. 20310–20320, 2024.
[17] Jonas Kulhanek, Songyou Peng, Zuzana Kukelova, Marc
Pollefeys, and Torsten Sattler, “WildGaussians: 3D Gaus-
sian splatting in the wild,” Adv. Neural Inf. Process. Syst.
(NeurIPS), 2024.
[18] Nicolas Moenne-Loccoz, Ashkan Mirzaei, Or Perel, Ric-
cardo de Lutio, Janick Martinez Esturo, Gavriel State, Sanja
Fidler, Nicholas Sharp, and Zan Gojcic, “3D Gaussian ray
tracing: Fast tracing of particle scenes,” ACM Trans. on
Graphics (TOG), vol. 43, no. 6, pp. 1–19, 2024.
[19] Qi Wu, Janick Martinez Esturo, Ashkan Mirzaei, Nicolas
Moenne-Loccoz, and Zan Gojcic, “3DGUT: Enabling dis-
torted cameras and secondary rays in Gaussian splatting,” in
IEEE Conf. Comput. Vis. Pattern Recog. (CVPR), pp. 26036–
26046, 2025.
[20] Hiroyuki Deguchi, Mana Masuda, Takuya Nakabayashi, and
Hideo Saito, “E2GS: Event enhanced gaussian splatting,”
in IEEE Int. Conf. Image Process. (ICIP), pp. 1676–1682,
2024.
[21] Marco Cannici and Davide Scaramuzza, “Mitigating motion
blur in neural radiance fields with events and frames,” in
IEEE Conf. Comput. Vis. Pattern Recog. (CVPR), 2024.
[22] Junhao He, Jiaxu Wang, Jia Li, Mingyuan Sun, Qiang Zhang,
Jiahang Cao, Ziyi Zhang, Yi Gu, Jingkai Sun, and Renjing
Xu, “DEGS: Deformable event-based 3d gaussian splatting
from rgb and event stream,” IEEE Trans. on Visualization
and Computer Graphics, 2025.
[23] Yufei Deng, Yuanjian Wang, Rong Xiao, Chenwei Tang,
Jizhe Zhou,
Jiahao Fan,
Deng Xiong,
Jiancheng Lv,
and Huajin Tang, “EBAD-Gaussian:
Event-driven bun-
dle adjusted deblur Gaussian splatting,” arXiv preprint
arXiv:2504.10012, 2025.
[24] Inwoo Hwang, Junho Kim, and Young Min Kim, “Ev-NeRF:
Event based neural radiance field,” in IEEE Winter Conf.
Appl. Comput. Vis. (WACV), pp. 837–847, 2023.
[25] Jiaxu Wang, Junhao He, Ziyi Zhang, and Renjing Xu, “Phys-
ical priors augmented event-based 3D reconstruction,” in
IEEE Int. Conf. Robot. Autom. (ICRA), pp. 16810–16817,
2024.
[26] Yuanjian Wang, Yufei Deng, Rong Xiao, Jiahao Fan, Chen-
wei Tang, Deng Xiong, and Jiancheng Lv, “SaENeRF: Sup-
pressing artifacts in event-based neural radiance fields,” in
Int. Joint Conf. Neural Netw. (IJCNN), 2025.
[27] Zixin Zhang, Kanghao Chen, and Lin Wang, “Elite-evgs:
13

<!-- page 14 -->
Learning event-based 3d gaussian splatting by distilling
event-to-video priors,” in IEEE Int. Conf. Robot. Autom.
(ICRA), pp. 13972–13978, 2025.
[28] Sohaib Zahid, Viktor Rudnev, Eddy Ilg, and Vladislav
Golyanik, “E-3dgs: Event-based novel view rendering of
large-scale scenes using 3d gaussian splatting,” Int. Conf. 3D
Vision (3DV), 2025.
[29] Tao Liu, Runze Yuan, Yi’ang Ju, Xun Xu, Jiaqi Yang, Xi-
angting Meng, Xavier Lagorce, and Laurent Kneip, “GS-
EVT: Cross-modal event camera tracking based on Gaus-
sian splatting,” in IEEE Int. Conf. Robot. Autom. (ICRA),
pp. 4587–4593, 2025.
[30] Simon Klenk, Lukas Koestler, Davide Scaramuzza, and
Daniel Cremers, “E-NeRF: Neural radiance fields from a
moving event camera,” IEEE Robot. Autom. Lett., vol. 8,
no. 3, pp. 1587–1594, 2023.
[31] Chaoran Feng, Wangbo Yu, Xinhua Cheng, Zhenyu Tang,
Junwu Zhang, Li Yuan, and Yonghong Tian, “AE-NeRF:
Augmenting event-based neural radiance fields for non-ideal
conditions and larger scenes,” in AAAI Conf. Artificial Intell.,
vol. 39, pp. 2924–2932, 2025.
[32] Hanqian Han, Jianing Li, Henglu Wei, and Xiangyang
Ji, “Event-3DGS: Event-based 3D reconstruction using
3D Gaussian splatting,” Adv. Neural Inf. Process. Syst.
(NeurIPS), vol. 37, pp. 128139–128159, 2024.
[33] Xiaoting Yin, Hao Shi, Yuhan Bao, Zhenshan Bing, Yiyi
Liao, Kailun Yang, and Kaiwei Wang, “E-3DGS: 3D Gaus-
sian splatting with exposure and motion events,” Applied Op-
tics, vol. 64, no. 14, pp. 3897–3908, 2025.
[34] Henri Rebecq, Ren´e Ranftl, Vladlen Koltun, and Davide
Scaramuzza, “High speed and high dynamic range video
with an event camera,” IEEE Trans. Pattern Anal. Mach. In-
tell., vol. 43, no. 6, pp. 1964–1980, 2021.
[35] Bohao Liao, Wei Zhai, Zengyu Wan, Zhixin Cheng, Wenfei
Yang, Tianzhu Zhang, Yang Cao, and Zheng-Jun Zha, “EF-
3DGS: Event-aided free-trajectory 3D Gaussian splatting,”
in Adv. Neural Inf. Process. Syst. (NeurIPS), 2025.
[36] David Weikersdorfer, David B. Adrian, Daniel Cremers,
and J¨org Conradt, “Event-based 3D SLAM with a depth-
augmented dynamic vision sensor,” in IEEE Int. Conf. Robot.
Autom. (ICRA), pp. 359–364, 2014.
[37] Emanuele Trucco and Alessandro Verri, Introductory Tech-
niques for 3-D Computer Vision. Upper Saddle River, NJ,
USA: Prentice Hall PTR, 1998.
[38] Guillermo Gallego and Davide Scaramuzza, “Accurate angu-
lar velocity estimation with an event camera,” IEEE Robot.
Autom. Lett., vol. 2, no. 2, pp. 632–639, 2017.
[39] Haram Kim and H. Jin Kim, “Real-time rotational motion
estimation with contrast maximization over globally aligned
events,” IEEE Robot. Autom. Lett., vol. 6, no. 3, pp. 6016–
6023, 2021.
[40] Shintaro Shiba, Yoshimitsu Aoki, and Guillermo Gallego,
“A fast geometric regularizer to mitigate event collapse in
the contrast maximization framework,” Adv. Intell. Syst.,
p. 2200251, 2022.
[41] Xin Peng, Ling Gao, Yifu Wang, and Laurent Kneip,
“Globally-optimal contrast maximisation for event cameras,”
IEEE Trans. Pattern Anal. Mach. Intell., vol. 44, no. 7,
pp. 3479–3495, 2022.
[42] Cheng Gu, Erik Learned-Miller, Daniel Sheldon, Guillermo
Gallego, and Pia Bideau, “The spatio-temporal Poisson point
process: A simple model for the alignment of event camera
data,” in Int. Conf. Comput. Vis. (ICCV), pp. 13495–13504,
2021.
[43] Shuang Guo and Guillermo Gallego, “CMax-SLAM: Event-
based rotational-motion bundle adjustment and SLAM sys-
tem using contrast maximization,” IEEE Trans. Robot.,
vol. 40, pp. 2442–2461, 2024.
[44] Shuang Guo and Guillermo Gallego, “Event-based photo-
metric bundle adjustment,” IEEE Trans. Pattern Anal. Mach.
Intell., vol. 47, no. 10, pp. 9280–9297, 2025.
[45] Shuang Guo, Friedhelm Hamann, and Guillermo Gallego,
“Unsupervised joint learning of optical flow and intensity
with event cameras,” in Int. Conf. Comput. Vis. (ICCV),
2025.
[46] Shintaro Shiba, Yoshimitsu Aoki, and Guillermo Gallego,
“Secrets of event-based optical flow,” in Eur. Conf. Comput.
Vis. (ECCV), pp. 628–645, 2022.
[47] Shintaro Shiba, Yannick Klose, Yoshimitsu Aoki, and
Guillermo Gallego, “Secrets of event-based optical flow,
depth, and ego-motion by contrast maximization,” IEEE
Trans. Pattern Anal. Mach. Intell., vol. 46, no. 12, pp. 7742–
7759, 2024.
[48] Javier Hidalgo-Carri´o, Guillermo Gallego, and Davide
Scaramuzza, “Event-aided direct sparse odometry,” in IEEE
Conf. Comput. Vis. Pattern Recog. (CVPR), pp. 5781–5790,
June 2022.
[49] Simon Klenk, Jason Chui, Nikolaus Demmel, and Daniel
Cremers, “TUM-VIE: The TUM stereo visual-inertial event
dataset,” in IEEE/RSJ Int. Conf. Intell. Robot. Syst. (IROS),
pp. 8601–8608, 2021.
[50] Zelin Zhang, Anthony Yezzi, and Guillermo Gallego, “For-
mulating event-based image reconstruction as a linear in-
verse problem with deep regularization using optical flow,”
IEEE Trans. Pattern Anal. Mach. Intell., vol. 45, no. 7,
pp. 8372–8389, 2023.
[51] Samuel Bryner, Guillermo Gallego, Henri Rebecq, and Da-
vide Scaramuzza, “Event-based, direct camera tracking from
a photometric 3D map using nonlinear optimization,” in
IEEE Int. Conf. Robot. Autom. (ICRA), 2019.
[52] Federico Paredes-Vall´es and Guido C. H. E. de Croon, “Back
to event basics: Self-supervised learning of image recon-
struction for event cameras via photometric constancy,” in
IEEE Conf. Comput. Vis. Pattern Recog. (CVPR), pp. 3445–
3454, 2021.
[53] Shintaro Shiba,
Friedhelm Hamann,
Yoshimitsu Aoki,
and Guillermo Gallego, “Event-based background oriented
schlieren,” IEEE Trans. Pattern Anal. Mach. Intell., vol. 46,
no. 4, pp. 2011–2026, 2024.
[54] Zhou Wang, Alan C. Bovik, Hamid R. Sheikh, and Eero P.
Simoncelli, “Image quality assessment: From error visibility
to structural similarity,” IEEE Trans. Image Process., vol. 13,
pp. 600–612, Apr. 2004.
[55] Henri Rebecq, Daniel Gehrig, and Davide Scaramuzza,
“ESIM: an open event camera simulator,” in Conf. on Robot
Learning (CoRL), vol. 87 of Proc. Machine Learning Re-
search, pp. 969–982, PMLR, 2018.
[56] Henri Rebecq, Guillermo Gallego, Elias Mueggler, and Da-
14

<!-- page 15 -->
vide Scaramuzza, “EMVS: Event-based multi-view stereo—
3D reconstruction with an event camera in real-time,” Int. J.
Comput. Vis., vol. 126, pp. 1394–1414, Dec. 2018.
[57] Minghao Yin, Yukang Cao, Songyou Peng, and Kai Han,
“Splat4D: Diffusion-enhanced 4d gaussian splatting for tem-
porally and spatially consistent content creation,” in SIG-
GRAPH, pp. 1–10, 2025.
[58] Shintaro Shiba, Yoshimitsu Aoki, and Guillermo Gallego,
“Event collapse in contrast maximization frameworks,” Sen-
sors, vol. 22, no. 14, pp. 1–20, 2022.
[59] Jianyuan Wang, Minghao Chen, Nikita Karaev, Andrea
Vedaldi, Christian Rupprecht, and David Novotny, “VGGT:
Visual Geometry Grounded Transformer,” in IEEE Conf.
Comput. Vis. Pattern Recog. (CVPR), pp. 5294–5306, 2025.
15
