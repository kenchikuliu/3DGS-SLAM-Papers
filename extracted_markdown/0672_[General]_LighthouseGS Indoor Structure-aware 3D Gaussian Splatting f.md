# LighthouseGS: Indoor Structure-aware 3D Gaussian Splatting for Panorama-Style Mobile Captures

Seungoh Han1\* Jaehoon Jang1\* Hyunsu Kim2 Jaeheung Surh2

Junhyung Kwak2 Hyowon Ha2â  Kyungdon Joo1â 

1Ulsan National Institute of Science and Technology (UNIST) 2Bucketplace

{seungohhan00, wkdwogns1997, gustnxodjs, jaeheungsurh

junhk0914, hyowonha.phd, kdjoo369}@gmail.com

## Abstract

We introduce LighthouseGS, a practical novel view synthesis framework based on 3D Gaussian Splatting that utilizes simple panorama-style captures from a single mobile device. While convenient, this rotation-dominant motion and narrow baseline make accurate camera pose and 3D point estimation challenging, especially in textureless indoor scenes. To address these challenges, LighthouseGS leverages rough geometric priors, such as mobile device camera poses and monocular depth estimation, and utilizes indoor planar structures. Specifically, we propose a new initialization method called plane scaffold assembly to generate consistent 3D points on these structures, followed by a stable pruning strategy to enhance geometry and optimization stability. Additionally, we present geometric and photometric corrections to resolve inconsistencies from motion drift and auto-exposure in mobile devices. Tested on real and synthetic indoor scenes, LighthouseGS delivers photorealistic rendering, outperforming state-of-the-art methods and enabling applications like panoramic view synthesis and object placement. Project page: https://vision3d-lab.github.io/lighthousegs/

## 1. Introduction

Photorealistic novel view synthesis (NVS) for indoor scenes is essential for bringing real-world experiences into virtual worlds, enabling authentic interaction. With the advent of neural rendering techniques, Neural Radiance Fields [38] have demonstrated remarkable performance in NVS. Recently, 3D Gaussian Splatting (3DGS) [28] has emerged as a powerful alternative, providing real-time rendering with high-fidelity view synthesis. Building on these approaches, several studies [3, 23, 49, 50] have explored their applications in AR/VR, such as indoor navigation and room tours.

<!-- image-->  
Figure 1. Comparison between complex capturing motion and panorama-style motion for novel view synthesis.

However, despite the high-quality rendering of existing NVS methods, their practical deployment remains limited for general users (i.e., non-experts). First, utilizing multicamera rigs [35, 45, 49] or 360â¦ cameras [3, 11, 32] allows for capturing the entire surrounding scene in a single shot, but these setups are often inaccessible due to their cost and complexity. Second, even with a single mobile device, most prior works [28, 36] still require hundreds of densely captured images with sufficient overlap. This capturing process is also impractical for general users, who typically do not walk through an entire space to capture images from all angles. Motivated by this fact, we explore a method for generating photorealistic NVS from casually captured indoor scenes, aiming to improve accessibility for non-expert users. Concretely, we leverage a panorama-style motion [44], a natural and practical way for users to capture their surroundings with a single mobile device, as illustrated in Fig. 1. Panorama-style motion, where users stand in place and rotate the camera with half-stretched arms, enables efficient scene coverage without professional equipment or complex procedures. However, integrating this motion into the NVS pipeline entails technical challenges. Due to its rotation-dominant motion and narrow baseline,

Structure-from-Motion (SfM) [43] often fails to estimate accurate camera pose and reliable 3D points, which are crucial for initializing NVS frameworks. These issues are further exacerbated in textureless regions of indoor scenes, resulting in degraded rendering quality.

In this work, we propose a practical 3DGS-based NVS framework for panorama-style captures of indoor scenes by a mobile device camera. Inspired by the panorama-style motion, which is similar to a lighthouse shining its light, we call the proposed method LighthouseGS. To overcome the challenges of SfM under panorama-style motion and indoor scenes, we introduce a new initialization scheme, plane scaffold assembly, that exploits ARKit camera poses and monocular depth estimates. Although these rough geometric priors may be imprecise due to IMU drift and scale ambiguity, plane scaffold assembly combines them with the planar structure of indoor scenes to derive more accurate Gaussian initialization by enforcing global and local consistency. Furthermore, we present a geometry-aware pruning strategy that improves optimization stability by retaining high-confidence Gaussians located in non-textured regions. This scheme facilitates stable updates of the geometric and visual aspects of the scene. Then, LighthouseGS performs end-to-end optimization of initial camera poses and color inconsistencies via differentiable rasterization, allowing it to correct motion drift and auto-exposure caused by mobile devices.

To train and validate our proposed framework, we newly construct real-world and synthetic datasets captured with panorama-style motion. Our dataset covers various indoor scenes and comprises auto-exposed images with their corresponding camera poses. As a result, LighthouseGS shows photorealistic rendering quality, outperforming previous neural rendering approaches. In addition, we further showcase two applications based on the proposed framework: panoramic view synthesis and object placement.

In summary, our contributions are as follows:

â¢ LighthouseGS is a practical NVS framework that allows general users to easily capture indoor scenes in panorama-style motion using a single mobile device.

â¢ Based on the indoor planar structure, we introduce a new alignment scheme, plane scaffold assembly, which facilitates initializing 3D Gaussians to fit the scene geometry.

â¢ We present a new stable pruning scheme that keeps Gaussians that have high opacity values in textureless regions, enhancing geometric quality and optimization stability.

â¢ We introduce geometric and photometric correction strategies to mitigate motion drift and color inconsistencies, resulting in better rendering quality.

## 2. Related work

Casual Multi-view Capture Motion. Capturing multiview images for 3D scene reconstruction has traditionally relied on professional multi-camera rigs [16, 35, 40, 48, 49]. However, these systems are often impractical for general users due to their complexity and cost. Recent advances have focused on more accessible methods that use a single mobile device for panoramic capture [5, 25], multi-view stitching [19, 20], and view synthesis [4]. Panorama-style motion [44] has emerged as a popular approach to casual capture, particularly for non-professional users. However, this method presents challenges for 3D scene representations, including small baselines, large view changes, and issues with non-textured regions in indoor environments. To address these challenges, we develop a method tailored to panorama-style inputs for robust indoor 3D scene representations.

Geometry-aligned 3D Gaussian Splatting. Recently, 3D Gaussian Splatting (3DGS) [28] has emerged as a promising framework, offering high-fidelity and real-time view synthesis through explicit 3D Gaussian primitives Several works have explored ways to improve the geometric accuracy of 3DGS. Approaches such as 2DGS [22] and SuGaR [18] have proposed modeling 2D oriented Gaussians, while FSGS [55] and DNGaussian [31] incorporate depth guidance in few-view settings. GaussianPro [12] and DN-Splatter [46] further leverage surface normals alongside depth, reducing ambiguity in non-textured regions. Beyond these low-level geometric cues, some methods [33, 41] utilize indoor structural priors, such as lines and planes, to regularize Gaussian optimization. Our work also contributes to this line of research by introducing geometric constraints that consider connectivity between depths and surface normals, tailored for indoor panoramic captures.

Optimizing Camera Pose with Radiance Fields. Accurate camera poses are crucial for high-quality 3D reconstruction and novel view synthesis. Previous works have explored joint optimization of camera parameters with implicit functions [8, 10, 34, 39]. With the advent of 3DGS, methods like CF-3DGS [17] and HT-3DGS [26] have emerged to estimate relative poses using depth priors and video frame interpolation, respectively. Other approaches [27, 37] enhance camera pose accuracy with correspondence matching, while InstantSplat [15] leverages a trained 3D foundation model [30] to regress initial camera pose and dense point maps. However, these methods struggle to reconstruct a 3D scene under panorama-style motion, which involves large rotation and small translation. To handle this challenge, we introduce a novel approach that initializes camera poses with AR poses and refines them via residual pose refinement.

## 3. Lighthouse Gaussian Splatting

Given a set of images {It} and initial poses $\left\{ \Pi _ { t } \right\}$ captured by panorama-style motion, we propose LighthouseGS, a practical 3DGS-based NVS framework for real-time rendering in indoor scenes. These inputs are easily acquired using smartphone apps [1] or built-in features like ARKit1 on iOS devices. As shown in Fig. 2, we first construct a plane scaffold of aligned 3D points $\mathcal { X } _ { T }$ and their corresponding normals $\mathcal { N } _ { T } .$ , ensuring global and local consistency (Sec. 3.1). From this plane scaffold, we initialize 3D Gaussians to be aligned to the indoor scene geometry, especially in textureless regions. In the optimization step, LighthouseGS introduces a simple yet effective pruning strategy and then applies geometric constraints to enhance optimization stability in textureless regions of indoor scenes (Sec. 3.2). While optimizing the 3D Gaussians, we further perform geometric and photometric corrections to resolve the motion drift of input camera poses and color inconsistency caused by autoexposure (Sec. 3.3). This process allows us to achieve photorealistic rendering from casually captured images without high-end cameras nor SfM.

<!-- image-->  
Figure 2. Overview of LighthouseGS. Given consecutive images captured by panorama-style motion with the corresponding rough geometric priors, we construct the plane scaffold that ensures global and local consistency. Then, we initialize 3D Gaussians to be aligned to scene geometry and optimize LighthouseGS with plane-aware stable optimization. To address motion drift and auto-exposure by the use of mobile devices, we additionally correct camera poses and view-dependent colors.

Preliminary of 3D Gaussian Splatting. 3DGS [28] explicitly represents the scene as a set of 3D Gaussian primitives, enabling real-time rendering via differentiable rasterization. Each Gaussian is expressed as $G ( x ) \ =$ $e ^ { - { \frac { 1 } { 2 } } ( x - \mu ) ^ { \top } \Sigma ^ { - 1 } ( x - \mu ) }$ , where $\mu$ indicates 3D mean position and $\Sigma \in \mathbb { R } ^ { 3 \times 3 }$ is a covariance matrix that is decomposed into a rotation matrix $R \in S O ( 3 )$ and a scale matrix $S \in$ $\mathbb { R } ^ { 3 \times 3 }$ Concisely, each primitive has learnable parameters $\left( \mu _ { i } , R _ { i } , S _ { i } , \alpha _ { i } , S H _ { i } \right)$ , where Î± and SH denote the opacity and spherical harmonics (SH) coefficients. To optimize these parameters, the covariance matrix is transformed into the camera space through local affine approximation [56]. Then, during the Î±-blending stage, rendered color C is computed by $\begin{array} { r } { C = \sum _ { i } ^ { N } c _ { i } \alpha _ { i } \bar { T _ { i } } } \end{array}$ , where $\begin{array} { r } { T _ { i } = \prod _ { j = 1 } ^ { i - 1 } \left( 1 - \alpha _ { j } \right) } \end{array}$ is the transmittance, $c _ { i }$ is the coefficient derived from the

SH basis functions, and N is the number of ordered Gaussians overlapping with the pixels.

## 3.1. Plane Scaffold Assembly

We present a new alignment scheme, plane scaffold assembly, that constructs globally aligned dense 3D points, leveraging planar structures from the rough geometric priors (i.e., monocular depth estimation [52] and ARKit poses), as shown in Fig. 3. Although these priors provide fairly accurate information, monocular depths between overlapping views suffer from scale ambiguity, resulting in inaccurate Gaussian initialization. To resolve this issue, we propose a two-stage approach for plane scaffold assembly: imagewise global alignment and plane-wise local alignment.

Image-wise Global Alignment. Given previous global points $\mathcal { X } _ { t - 1 }$ and a new depth image $D _ { t }$ , image-wise global alignment aims to predict an affine transformation that adjusts a given depth image to fit the global points. Note that directly aligning depth with global points in 3D is a nontrivial problem due to the requirement of point-wise correspondences. Instead, we project the global points into the current frame and then align them in 2D space.

We represent an adjusted depth map by affine transformation as $\bar { D } _ { t } = \alpha _ { t } D _ { t } + \beta _ { t }$ with the learnable per-view scale and shift parameters $( \alpha _ { t } , \beta _ { t } ) \in \mathbb { R }$ These parameters are optimized via a gradient descent manner to minimize error between the current depth and projected global points, similar to the depth alignment in Text2Room [21]. While this image-wise global alignment yields overall improvements, relying on a single scale and shift parameter to adjust 3D space for various objects in indoor scenes causes local inconsistency, as shown in Fig. 4. Note that, as the reference scale, we initialize a set of aligned 3D points $\mathcal { X } _ { 0 }$ from the first depth frame $D _ { 0 }$ by back-projection.

<!-- image-->  
Figure 3. Overview of plane scaffold assembly. Inputs are sequentially merged into the plane scaffold. The estimated depth from the current frame is globally-to-locally aligned with the projected global points from the previous set.

<!-- image-->  
Figure 4. Effect of plane-wise local alignment. Although the blue points of global alignment include local inconsistency, plane-wise local alignment ensures local consistency.

Plane-wise Local Alignment. We optimize per-plane scale and shift values to enforce local consistency on globally aligned 3D points. To this end, we leverage planar geometry in indoor scenes, where depth values with similar normal directions in local regions can be grouped into the same plane. We extract such planar regions via efficient mean-shift clustering [54] on an estimated depth $D _ { t }$ and surface normal map $N _ { t }$ , even when the exact number of planes is unknown. We represent each planar region as a plane segment mask $m _ { t } ^ { p } \in \mathbf { \bar { \mathbb { R } } } ^ { H \times W }$ as a form of a binary mask. Then, we define the per-plane scale and shift parameters $( \gamma _ { t } ^ { p } , \delta _ { t } ^ { p } )$ for each plane p. Initial values are initialized with the global parameters $( \alpha _ { t } , \beta _ { t } )$ . The scaled depth $\bar { D } _ { t } ^ { p }$ for each plane p is computed by multiplying the plane mask as follows:

$$
\bar { D } _ { t } ^ { p } = m _ { t } ^ { p } \odot ( \gamma _ { t } ^ { p } D _ { t } ^ { p } + \delta _ { t } ^ { p } ) .\tag{1}
$$

These local plane regions are optimized while minimizing the projection loss between each plane segment and the projected depth within the overlapped pixels as follows:

$$
\begin{array} { r } { a r g m i n | | M \odot ( \bar { D } _ { t } ^ { p } - \pi ( \mathcal { X } _ { t - 1 } ; \Pi _ { t } ) ) | | _ { 1 } , } \\ { \gamma _ { t } ^ { p } , \delta _ { t } ^ { p } \phantom { x x x x x x x x x x x x x x x x x x x x x x x x x x x x x } } \end{array}\tag{2}
$$

where M denotes a mask for the overlapped pixels between the scaled plane depth $\bar { D } _ { t } ^ { p }$ and the projected global points. Finally, we back-project the adjusted plane segments to obtain the 3D points in the world space. They are merged to the global points $\mathcal { X } _ { t - 1 }$ except for the overlapping pixels by:

$$
\mathcal { X } _ { t } = \mathcal { X } _ { t - 1 } \cup \pi ^ { - 1 } ( \bar { D } _ { t } ^ { p } ; \Pi _ { t } ) ,\tag{3}
$$

where $\pi ^ { - 1 } ( \cdot ; \cdot )$ denotes a back-projection function that back-projects globally-to-locally aligned planes into the world space using the camera pose. Thanks to the local plane-wise alignment, we observe that the 3D points are correctly aligned across various objects or planar regions. In addition, each 3D point has a normal direction belonging to its plane, which guides the initialized 3D Gaussians to be aligned well with the scene geometry from the power of plane hints for indoor environments. The transformed plane normal directions are aggregated into the plane scaffold as a set of normal vectors $\mathcal { N } _ { t }$ in a similar manner to what is done in Eq. (3) with the global 3D points Xt.

Finally, we generate globally-to-locally aligned points with plane information called the plane scaffold $s \ =$ $( \mathcal { X } _ { T } , \mathcal { N } _ { T } )$ . It successfully estimates a set of plane-guided 3D points for initializing 3DGS on our practical and challenging panorama-style motion that fails on COLMAP [43], as shown in Fig. 8. We downsample this plane scaffold to keep the proper number of points.

## 3.2. Plane-aware Stable Optimization

Plane-guided Initialization. Given a set of aligned 3D points, we initialize 3D Gaussian primitives to be aligned to the surface normals in the plane scaffold. Following 3DGS [28], a set of Gaussians begins with the position of the global 3D points. The initial scale of each Gaussian is determined by the average distance from its nearest neighbors, resulting in an isotropic shape. These isotropic Gaussians roughly populate the 3D world space without leaving empty regions, which does not represent the planar structure largely distributed in indoor scenes. Thus, we compress the initialized 3D Gaussians by minimizing the scale of the axis closest to the surface normal. By assigning the minimal value to the scale, the 3D Gaussians are initialized with thin structures flattened along the surface plane.

Stable Pruning. The existing pruning scheme [28] often removes oversized Gaussians in non-textured regions. This degrades optimization stability since the empty holes are filled inappropriately, causing geometric artifacts after optimization (see top part of Fig. 5).

To prevent such artifacts, we introduce a stable pruning strategy that retains reliable 3D Gaussians in textureless regions. Intuitively, 3D Gaussians aligned with the surface possess high opacity values. In addition, since textureless regions do not require fine details, they can be effectively represented with larger Gaussians. Motivated by these observations, we assess the reliability of 3D Gaussians based on their opacity. Specifically, we first collect pruning candidates for oversized Gaussians within the overlapping regions in the image domain. Then, we retain the high-confidence Gaussians among the candidates whose opacity value is higher than a threshold 0.5. This simple yet effective strategy enhances optimization stability by retaining large Gaussians, thereby preventing large holes in non-textured regions. As a result, stable pruning produces smooth geometry without floaters in textureless regions, ensuring precise scene representation (see bottom part of Fig. 5).

<!-- image-->  
Figure 5. Effect of stable pruning. Unlike previous pruning schemes, stable pruning keeps highly confident Gaussians, preserving precise scene geometry in textureless areas.

Plane-guided Regularization. While the 3D Gaussians are initialized with the proposed plane scaffold, relying solely on the rendering loss does not guarantee their geometric accuracy during optimization. Thus, we apply additional loss functions to align the 3D Gaussians with the scene geometry.

Angular Loss. To enforce each Gaussian to be aligned with the surface, we constrain its normal direction as follows:

$$
\mathcal { L } _ { c o s } = 1 - c o s ( \hat { N } , N ) ,\tag{4}
$$

where $\hat { N }$ is the rendered normal map, and N is the estimated normal map from the pre-trained network [2]. Following [12], we can compute $\hat { N } _ { t }$ by replacing each Gaussianâs color $c _ { i }$ with its normal $n _ { i }$ , where $n _ { i }$ is a rotation axis having the minimal scale value.

Flatten Loss. We also regularize the minimal scale of each Gaussian to be flattened along the surface, inspired by NeuSG [9]:

$$
\mathcal { L } _ { f l a t } = | | m i n ( s _ { 1 } , s _ { 2 } , s _ { 3 } ) | | _ { 1 } ,\tag{5}
$$

where $s _ { i }$ denotes the scale value of each axis of the 3D Gaussian in the world space.

Normal Smoothness Loss. 3DGS often struggles with representing smooth geometry due to its unstructured form. To mitigate this issue, we apply a total variation term [42] to

the rendered normal:

$$
\mathcal { L } _ { s m o o t h } = \frac { 1 } { L } \sum _ { i , j } | \nabla _ { x } \hat { N } ( i , j ) | + | \nabla _ { y } \hat { N } ( i , j ) | ,\tag{6}
$$

where $( i , j )$ denotes the pixel coordinates and $\nabla _ { x } \hat { N }$ and $\nabla _ { y } \hat { N }$ are the horizontal and vertical gradient of the rendered normal map $\hat { N } ,$ and L is the number of pixels.

Depth-to-Normal Consistency Loss. We regularize the rendered depth map to be consistent in local regions using the normal map. To do this, we back-project the rendered depth map DË into a per-pixel 3D location map. Then, depth-tonormal consistency is enforced by encouraging the horizontal and vertical gradients of 3D locations to be orthogonal to the corresponding normal direction:

$$
\mathcal { L } _ { d 2 n } = \frac { 1 } { L } \sum _ { i , j } | \nabla _ { x } \hat { D } ( i , j ) \cdot \boldsymbol { N } ( i , j ) | + | \nabla _ { y } \hat { D } ( i , j ) \cdot \boldsymbol { N } ( i , j ) | ,\tag{7}
$$

where $\nabla _ { x } \hat { D }$ and $\nabla _ { y } \hat { D }$ are the spatial gradient of the 3D location $\hat { D }$ and L is the number of pixels.

## 3.3. Geometric and Photometric Correction

Plane scaffold assembly and plane-aware stable optimization mitigate the limitations of existing 3DGS in indoor scenes. However, our framework still inherits challenges like motion drift and auto-exposure/white balance from mobile capture. To alleviate these issues, we present two strategies: residual pose refinement and color correction.

Residual Pose Refinement. Inspired by PoRF [7], we optimize residual pose instead of directly refining camera pose parameters. We initialize residual pose parameters for each frame as an identity rotation matrix (quaternion form) and zero translation vector. During optimizing 3DGS, a quaternion and translation vector are transformed into the residual pose $\Delta \Pi \in S E ( 3 )$ . To obtain an adjusted pose, the residual pose is multiplied by the initial pose:

$$
\begin{array} { r } { \tilde { \Pi } _ { t } = \Delta \Pi _ { t } \cdot \Pi _ { t } , } \end{array}\tag{8}
$$

where $\tilde { \Pi } _ { t }$ indicates the adjusted pose with the learnable residual parameters, but the camera intrinsic is fixed. Then, we compare the rendered image utilizing the adjusted pose with the ground truth image. Since the image is rendered with the adjusted pose in a differentiable renderer, gradients can be backpropagated to update the residual pose. With the residual pose refinement, we render geometrically consistent views while alleviating motion drift, particularly in later sequences where drift errors accumulate.

Color Correction. Captured images from mobile devices are typically subject to auto-exposure and white balance, leading to color inconsistencies across different viewpoints. Color variations at the same location disrupt the consistency of 3DGS in learning geometry and color. Varying colors across different views are corrected via a simple color transformation strategy parameterized by learnable white balancing $w \in \mathbb { R } ^ { 3 }$ and brightness $b \in \mathbb { R } ^ { 3 }$ as channel-wise parameters. A rendered image $\hat { I } _ { t }$ is transformed into the color corrected image ${ \tilde { I } } _ { t }$ before calculating rendering loss:

$$
\tilde { I } _ { t } = w _ { t } \hat { I } _ { t } + b _ { t } .\tag{9}
$$

The learnable coefficients are updated via differentiable rasterization, backpropagating the gradients into these parameters. This approach compensates for color differences and learns a global color space to improve visual quality.

## 3.4. Objective Function

To train the proposed LighthouseGS, the final loss term L consists of a photometric and geometric constraint:

$$
\begin{array} { r } { \mathcal { L } = \mathcal { L } _ { c o l o r } + \mathcal { L } _ { g e o } . } \end{array}\tag{10}
$$

Photometric loss $\mathcal { L } _ { c o l o r }$ guides explicit 3D Gaussians for reducing photometric differences between ground truth images I and corrected images ËI from rendered image ËI:

$$
\mathcal { L } _ { c o l o r } = \lambda _ { l 1 } \mathcal { L } _ { l 1 } + \lambda _ { D - S S I M } \mathcal { L } _ { D - S S I M } ,\tag{11}
$$

$$
\mathcal { L } _ { l 1 } = | | I - \tilde { I } | | _ { 1 } , \mathcal { L } _ { D - S S I M } = 1 - S S I M ( I , \tilde { I } ) ,\tag{12}
$$

where $\lambda _ { l 1 }$ and $\lambda _ { D - S S I M }$ are set to 0.8 and 0.2, respectively.

Geometric loss $\mathcal { L } _ { g e o }$ regularizes the rendered geometry to align 3D Gaussians along the surface using prior geometry. The total geometric constraints are given by:

$$
\mathcal { L } _ { g e o } = \lambda _ { n o r m a l } ( \mathcal { L } _ { c o s } + \mathcal { L } _ { f l a t } + \mathcal { L } _ { s m o o t h } ) + \lambda _ { d 2 n } \mathcal { L } _ { d 2 n } ,\tag{13}
$$

where we set $\lambda _ { n o r m a l } = 0 . 0 5 \mathrm { a n d } \lambda _ { d 2 n } = 0 . 2 .$

## 4. Experiments

## 4.1. Dataset

Due to the absence of indoor scene datasets captured by panorama-style motion, we construct a new dataset in real and synthetic environments to evaluate our LighthouseGS framework. We visualize the collected dataset in the supplementary material.

Real-world Scenario. We use Nerfcapture [1] that saves a set of images with the camera parameters from iPhoneâs ARKit. We rotate the device with outstretched half-arms while capturing the region of interest. A set of images covers almost the entire space from the motion center. This natural motion does not strictly follow the original spherical motion [47], and panorama-style motion means rather a more practical and less constrained method. Our dataset comprises five different indoor environments, each with up to 100 images at 1920 Ã 1440 resolution.

Synthetic Scenario. We create a synthetic dataset with Blender [13], which supports physically-based rendering.

<table><tr><td>Dataset</td><td>Method</td><td>PSNR â</td><td>SSIMâ</td><td>LPIPS â</td></tr><tr><td rowspan="5">Real-world</td><td>3DGSâ </td><td>20.60</td><td>0.684</td><td>0.387</td></tr><tr><td>DNGaussianâ </td><td>21.10</td><td>0.724</td><td>0.394</td></tr><tr><td>Scaffold-GSâ </td><td>21.11</td><td>0.707</td><td>0.338</td></tr><tr><td>GeoGaussianâ </td><td>20.53</td><td>0.687</td><td>0.311</td></tr><tr><td>LighthouseGS</td><td>25.06</td><td>0.809</td><td>0.317</td></tr><tr><td rowspan="6">Synthetic</td><td>3DGSâ </td><td>24.10</td><td>0.790</td><td>0.252</td></tr><tr><td>DNGaussianâ </td><td>23.80</td><td>0.806</td><td>0.312</td></tr><tr><td>Scaffold-GSâ </td><td>23.64</td><td>0.781</td><td>0.251</td></tr><tr><td>GeoGaussianâ </td><td>24.14</td><td>0.800</td><td>0.263</td></tr><tr><td>LighthouseGS</td><td>28.86</td><td>0.898</td><td>0.122</td></tr><tr><td></td><td></td><td></td><td></td></tr></table>

Table 1. Quantitative comparisons on real and synthetic datasets. â  indicates methods that initialize with plane scaffold assembly. We highlight the best and second performances in bold and underline.

We render synthetic images at a radius of 20 or 30 cm from the fixed center of panorama-style motion, depending on the scale of the scene. Based on a statistical analysis of ARKit tracking [29], we further add drift noise to the ground truth camera poses to mimic pose errors. It consists of five indoor scenes, each with 100 auto-exposure images at 1024Ã1024 resolution and their corresponding camera poses.

## 4.2. Implementation Details

LighthouseGS is built on the gsplat [53]. For Gaussian densification, a gradient threshold is set to 0.0008 and 0.0004 for real and synthetic scenes, respectively. All other configurations follow the original settings in 3DGS [28], and the experiments are conducted on a single RTX 4090 GPU. Following [17], we freeze the trained 3D Gaussians and optimize the camera poses and tone mapping parameters of test views over 20K iterations to evaluate unseen viewpoints. Then, we measure PSNR, SSIM, and LPIPS.

## 4.3. Evaluation

We evaluate LighthouseGS with state-of-the-art 3DGSbased approaches: 3DGS [28], DNGaussian [31], Scaffold-GS [36], and GeoGaussian [33]. All comparisons rely on pre-computed 3D points and camera poses from COLMAP [43]. However, it fails under panorama-style motion, making it impossible to execute the methods. To address this, we initialize baselines using 3D points from our proposed plane scaffold assembly and ARKit poses for a fair comparison (denoted as â ).

Quantitative Evaluation. We report average quantitative results for the collected real-world and synthetic datasets (see Table 1). LighthouseGS outperforms previous methods across all metrics on both datasets. These significant improvements demonstrate that LighthouseGS effectively resolves inherent problems posed by capturing indoor scenes with panorama-style motion using mobile devices. In other words, our plane-aware optimization scheme handles artifacts in textureless regions while pose refinement mitigates motion drift, resulting in more accurate reconstructions. It should be noted that per-scene metrics and computational efficiency (e.g., memory usage, training time, and FPS) are provided in the supplementary material.

<!-- image-->  
Figure 6. Qualitative comparisons on the real-world (top) and synthetic datasets (bottom). In contrast to other methods, LighthouseGS clearly reconstructs details of textured shapes without blurry artifacts (see red boxes). Also, we can observe that our method preserves accurate scene geometry without floaters in non-textured regions (see blue boxes).

Qualitative Evaluation. Figure 6 shows novel view synthesis results on a real-world and synthetic dataset. Overall, LighthouseGS achieves high-fidelity rendering while preserving accurate scene geometry. For example, unlike comparison methods that cause floaters and over-smoothed surfaces in textureless regions, LighthouseGS suffers less from such artifacts (see blue boxes). We deduce that retaining high-confidence 3D Gaussians in these areas by stable pruning prevents artifacts, resulting in accurate scene geometry. Moreover, our method is robust to inaccurate input camera poses and auto-exposure images (see red boxes). As illustrated at the bottom of Fig. 6, LighthouseGS yields similar performance on the synthetic dataset. In particular, due to changing exposure values as the camera rotates away from the window where the light comes in, other methods render visually inconsistent results (see blue boxes in the playroom). In contrast, LighthouseGS compensates for color differences by learning global color space through color correction, which synergizes with stable optimization and pose refinement to improve rendering quality. As shown in Fig. 7, our method well represents soft furnishings and curved objects (e.g., curtains and vase), demonstrating generalization beyond planar structures.

<table><tr><td>Methods</td><td>PSNR â</td><td>SSIM â</td><td>LPIPS â</td><td># of Gaussians â</td></tr><tr><td>3DGSâ </td><td>22.12</td><td>0.803</td><td>0.335</td><td>3.9M</td></tr><tr><td>w/o res. pose</td><td>23.25</td><td>0.850</td><td>0.339</td><td>0.46M</td></tr><tr><td>w/o color corr.</td><td>24.64</td><td>0.884</td><td>0.298</td><td>0.6M</td></tr><tr><td>w/o stable optim.</td><td>26.47</td><td>0.884</td><td>0.284</td><td>0.92M</td></tr><tr><td>Ours (full model)</td><td>26.80</td><td>0.888</td><td>0.287</td><td>0.51M</td></tr></table>

Table 2. Module ablation. We ablate our three important modules in pantry. The best scores are highlighted as bold.

<table><tr><td>Methods</td><td>PSNR â</td><td>SSIMâ</td><td>LPIPS â</td></tr><tr><td>COLMAP</td><td>N/A</td><td>N/A</td><td>N/A</td></tr><tr><td>Spherical SfM</td><td>17.41</td><td>0.660</td><td>0.440</td></tr><tr><td>ARKit + COLMAP</td><td>17.72</td><td>0.654</td><td>0.443</td></tr><tr><td>ARKit + Plane Scaffold (Ours)</td><td>23.52</td><td>0.789</td><td>0.300</td></tr></table>

Table 3. Initialization ablation. We compare different initializations with native 3DGS in the conference room.

## 4.4. Ablation Study

Module Ablation. We ablate each proposed component of our framework to demonstrate its effectiveness compared to the baseline (see Table 2). Each module contributes to improved performance across all metrics, even with fewer Gaussians. Since we follow adaptive density control, which relies on view space gradients, the residual pose refinement and color correction enhance rendering quality, resulting in smaller gradients that reduce the number of Gaussians. In addition, we observe that stable optimization is effective in further improving performance. Although stable optimization marginally improves photometric quality, it leads to a significant reduction in the number of Gaussians and enhances scene geometry fitting, as shown in Fig. 7. We deduce that this strategy prevents mis-densification in nontextured regions by preserving highly confident 3D Gaussians. To justify the proposed modules, we include further ablation studies in the supplementary materials.

<!-- image-->  
Figure 7. Effect of stable optimization. Stable optimization ensures Gaussian primitives can render consistent geometry, alleviating textureless artifacts and floaters.

<table><tr><td>Methods</td><td>PSNR â</td><td>SSIMâ</td><td>LPIPS â</td></tr><tr><td>ZoeDepth+DSINE</td><td>26.25</td><td>0.839</td><td>0.194</td></tr><tr><td>DA-V2+Omnidata</td><td>26.87</td><td>0.841</td><td>0.188</td></tr><tr><td>DA-V2+DSINE (Ours)</td><td>26.96</td><td>0.853</td><td>0.219</td></tr></table>

Table 4. Ablation on monocular priors. We report the sensitivity of monocular priors by alternating different backbone networks.

Initialization Ablation. In Table 3, we validate the efficacy of our plane scaffold assembly by altering the initialization algorithm in 3DGS. Since COLMAP often fails under a panorama-style motion setting, we triangulate a bundle of points with ARKit poses (denoted as ARKit + COLMAP). While ARKit enables COLMAP reconstruction, it still produces inaccurate camera poses and 3D points, resulting in lower rendering quality. Spherical SfM [47] is limited due to the strong constraint that cameras must lie on the sphere to operate successfully. Also, Fig. 8 shows initial point clouds generated by various methods, including the geometric foundation model Fast3R [51]. As a result, our plane scaffold assembly shows robust performance in both qualitative and quantitative aspects.

Sensitivity to Priors. We utilize monocular depth and normal estimation to construct globally-to-locally aligned 3D points in the plane scaffold assembly. To assess sensitivity to rendering quality, we conduct quantitative experiments by replacing Depth Anything V2 (DA-V2) [52] and DSINE [2] with ZoeDepth [6] and Omnidata [14], respectively. As reported in Table 4, even with lower quality depth or normal inputs, our method shows comparable performance, demonstrating its robustness to monocular priors. Moreover, with ongoing advances in monocular estimation, such sensitivity will become less critical in practice.

<!-- image-->  
Figure 8. Qualitative comparisons of initial point clouds.

## 5. Applications

Object Placement. We demonstrate the applicability of LighthouseGS to AR applications such as object placement (see Fig. 2). Accurate placement of virtual objects at desired locations requires precise scene geometry to ensure seamless alignment with the physical environment. With the geometrically aligned scene from LighthouseGS, virtual objects can be naturally inserted into the scene.

Panoramic View Synthesis. Panoramic imaging presents the entire indoor scene in a single image, making it useful in AR/VR applications. Thanks to our panorama-style motion setting, we can render panoramic images from an unseen viewpoint with the sphere-based rasterizer [24]. Additional results, including object placement and panoramic rendering, are available in the supplementary material.

## 6. Conclusion

We propose LighthouseGS, a practical 3DGS-based novel view synthesis framework for indoor scenes from panorama-style motion capture with a single mobile device. By incorporating the planar structure into the entire pipeline, we introduce a planar scaffold for consistent 3D alignment and a plane-aware optimization strategy that retains highly confident Gaussians in non-textured regions. We further correct inaccurate camera poses and autoexposure artifacts to enhance visual quality. Experiments demonstrate photorealistic rendering with accurate scene geometry, broadening the applicability of 3DGS to casual mobile capture scenarios.

## Acknowledgements

This work was supported by Bucketplace, by Institute of Information & communications Technology Planning & Evaluation (IITP) grant funded by the Korea government (MSIT) (No.RS-2022-II220907, Development of AI Bots Collaboration Platform and Self-organizing; No.RS-2020- II201336, Artificial Intelligence Graduate School Program (UNIST)) and by the InnoCORE program of the Ministry of Science and ICT (25-InnoCORE-01).

## References

[1] Jad Abou-Chakra. Nerfcapture, 2023. 3, 6

[2] Gwangbin Bae and Andrew J. Davison. Rethinking inductive biases for surface normal estimation. In CVPR, 2024. 5, 8

[3] Jiayang Bai, Letian Huang, Jie Guo, Wen Gong, Yuanqi Li, and Yanwen Guo. 360-gs: Layout-guided panoramic gaussian splatting for indoor roaming. arXiv preprint arXiv:2402.00763, 2024. 1

[4] Tobias Bertel and Christian Richardt. Megaparallax: 360Â° panoramas with motion parallax. In SIGGRAPH Posters, 2018. 2

[5] Tobias Bertel, Mingze Yuan, Reuben Lindroos, and Christian Richardt. Omniphotos: casual 360 vr photography. ACM TOG, 39(6):1â12, 2020. 2

[6] Shariq Farooq Bhat, Reiner Birkl, Diana Wofk, Peter Wonka, and Matthias Muller. Zoedepth: Zero-shot trans- Â¨ fer by combining relative and metric depth. arXiv preprint arXiv:2302.12288, 2023. 8

[7] Jia-Wang Bian, Wenjing Bian, Victor Adrian Prisacariu, and Philip Torr. Porf: Pose residual field for accurate neural surface reconstruction. In ICLR, 2024. 5

[8] Wenjing Bian, Zirui Wang, Kejie Li, Jiawang Bian, and Victor Adrian Prisacariu. Nope-nerf: Optimising neural radiance field with no pose prior. In CVPR, 2023. 2

[9] Hanlin Chen, Chen Li, and Gim Hee Lee. Neusg: Neural implicit surface reconstruction with 3d gaussian splatting guidance. arXiv preprint arXiv:2312.00846, 2023. 5

[10] Yu Chen and Gim Hee Lee. Dbarf: Deep bundle-adjusting generalizable neural radiance fields. In CVPR, 2023. 2

[11] Zheng Chen, Yan-Pei Cao, Yuan-Chen Guo, Chen Wang, Ying Shan, and Song-Hai Zhang. Panogrf: Generalizable spherical radiance fields for wide-baseline panoramas. In NIPS, 2023. 1

[12] Kai Cheng, Xiaoxiao Long, Kaizhi Yang, Yao Yao, Wei Yin, Yuexin Ma, Wenping Wang, and Xuejin Chen. Gaussianpro: 3d gaussian splatting with progressive propagation. In ICML, 2024. 2, 5

[13] Blender Online community. Blender - a 3D modelling and rendering package. Blender Foundation, Stitching Blender Foundation, Amsteradm, 2018. 6

[14] Ainaz Eftekhar, Alexander Sax, Jitendra Malik, and Amir Zamir. Omnidata: A scalable pipeline for making multi-task mid-level vision datasets from 3d scans. In ICCV, 2021. 8

[15] Zhiwen Fan, Kairun Wen, Wenyan Cong, Kevin Wang, Jian Zhang, Xinghao Ding, Danfei Xu, Boris Ivanovic,

Marco Pavone, Georgios Pavlakos, et al. Instantsplat: Sparse-view gaussian splatting in seconds. arXiv preprint arXiv:2403.20309, 2024. 2

[16] J. Flynn, M. Broxton, P. Debevec, M. DuVall, G. Fyffe, R. Overbeck, N. Snavely, and R. Tucker. Deepview: View synthesis with learned gradient descent. In CVPR, 2019. 2

[17] Yang Fu, Sifei Liu, Amey Kulkarni, Jan Kautz, Alexei A. Efros, and Xiaolong Wang. Colmap-free 3d gaussian splatting. In CVPR, 2024. 2, 6

[18] Antoine Guedon and Vincent Lepetit. Sugar: Surface- Â´ aligned gaussian splatting for efficient 3d mesh reconstruction and high-quality mesh rendering. In CVPR, 2024. 2

[19] Peter Hedman and Johannes Kopf. Instant 3d photography. ACM TOG, 37(4):1â12, 2018. 2

[20] Peter Hedman, Suhib Alsisan, Richard Szeliski, and Johannes Kopf. Casual 3d photography. ACM TOG, 36(6): 1â15, 2017. 2

[21] Lukas Hollein, Ang Cao, Andrew Owens, Justin Johnson, Â¨ and Matthias NieÃner. Text2room: Extracting textured 3d meshes from 2d text-to-image models. In ICCV, 2023. 3

[22] Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger, and Shenghua Gao. 2d gaussian splatting for geometrically accurate radiance fields. In SIGGRAPH, 2024. 2

[23] Huajian Huang, Yingshu Chen, Tianjia Zhang, and Sai-Kit Yeung. Real-time omnidirectional roaming in large scale indoor scenes. In SIGGRAPH Asia Technical Communications, 2022. 1

[24] Letian Huang, Jiayang Bai, Jie Guo, Yuanqi Li, and Yanwen Guo. On the error analysis of 3d gaussian splatting and an optimal projection strategy. In ECCV, 2024. 8

[25] Hyeonjoong Jang, Andreas Meuleman, Dahyun Kang, Donggun Kim, Christian Richardt, and Min H Kim. Egocentric scene reconstruction from an omnidirectional video. ACM TOG, 41(4):1â12, 2022. 2

[26] Bo Ji and Angela Yao. Sfm-free 3d gaussian splatting via hierarchical training. In CVPR, 2025. 2

[27] Kaiwen Jiang, Yang Fu, Mukund Varma T, Yash Belhe, Xiaolong Wang, Hao Su, and Ravi Ramamoorthi. A constructoptimize approach to sparse view synthesis without camera pose. In SIGGRAPH, 2024. 2

[28] Bernhard Kerbl, Georgios Kopanas, Thomas Leimkuhler, Â¨ and George Drettakis. 3d gaussian splatting for real-time radiance field rendering. ACM TOG, 42(4):139â1, 2023. 1, 2, 3, 4, 6

[29] Pyojin Kim, Jungha Kim, Minkyeong Song, Yeoeun Lee, Moonkyeong Jung, and Hyeong-Geun Kim. A benchmark comparison of four off-the-shelf proprietary visualâinertial odometry systems. Sensors, 22(24):9873, 2022. 6

[30] Vincent Leroy, Yohann Cabon, and JerÂ´ ome Revaud. Ground-Ë ing image matching in 3d with mast3r. In ECCV, 2024. 2

[31] Jiahe Li, Jiawei Zhang, Xiao Bai, Jin Zheng, Xin Ning, Jun Zhou, and Lin Gu. Dngaussian: Optimizing sparse-view 3d gaussian radiance fields with global-local depth normalization. In CVPR, 2024. 2, 6

[32] Longwei Li, Huajian Huang, Sai-Kit Yeung, and Hui Cheng. Omnigs: Fast radiance field reconstruction using omnidirectional gaussian splatting. In WACV, 2025. 1

[33] Yanyan Li, Chenyu Lyu, Yan Di, Guangyao Zhai, Gim Hee Lee, and Federico Tombari. Geogaussian: Geometry-aware gaussian splatting for scene rendering. In ECCV, 2024. 2, 6

[34] Chen-Hsuan Lin, Wei-Chiu Ma, Antonio Torralba, and Simon Lucey. Barf: Bundle-adjusting neural radiance fields. In ICCV, 2021. 2

[35] Kai-En Lin, Zexiang Xu, Ben Mildenhall, Pratul P. Srinivasan, Yannick Hold-Geoffroy, Stephen DiVerdi, Qi Sun, Kalyan Sunkavalli, and Ravi Ramamoorthi. Deep multi depth panoramas for view synthesis. In ECCV, 2020. 1, 2

[36] Tao Lu, Mulin Yu, Linning Xu, Yuanbo Xiangli, Limin Wang, Dahua Lin, and Bo Dai. Scaffold-gs: Structured 3d gaussians for view-adaptive rendering. In CVPR, 2024. 1, 6

[37] Andreas Meuleman, Ishaan Shah, Alexandre Lanvin, Bernhard Kerbl, and George Drettakis. On-the-fly reconstruction for large-scale novel view synthesis from unposed images. ACM TOG, 44(4):1â14, 2025. 2

[38] Ben Mildenhall, Pratul P. Srinivasan, Matthew Tancik, Jonathan T. Barron, Ravi Ramamoorthi, and Ren Ng. Nerf: Representing scenes as neural radiance fields for view synthesis. In ECCV, 2020. 1

[39] Keunhong Park, Philipp Henzler, Ben Mildenhall, Jonathan T Barron, and Ricardo Martin-Brualla. Camp: Camera preconditioning for neural radiance fields. ACM TOG, 42(6):1â11, 2023. 2

[40] Albert Parra Pozo, Michael Toksvig, Terry Filiba Schrager, Joyce Hsu, Uday Mathur, Alexander Sorkine-Hornung, Rick Szeliski, and Brian Cabral. An integrated 6dof video camera and system design. ACM TOG, 38(6):1â16, 2019. 2

[41] Cong Ruan, Yuesong Wang, Tao Guan, Bin Zhang, and Lili Ju. Indoorgs: Geometric cues guided gaussian splatting for indoor scene reconstruction. In CVPR, 2025. 2

[42] Leonid I Rudin, Stanley Osher, and Emad Fatemi. Nonlinear total variation based noise removal algorithms. Physica D: nonlinear phenomena, 60(1-4):259â268, 1992. 5

[43] Johannes L. Schonberger and Jan-Michael Frahm. Structure- Â¨ from-motion revisited. In CVPR, 2016. 2, 4, 6

[44] Chris Sweeney, Aleksander Holynski, Brian Curless, and Steve M Seitz. Structure from motion for panorama-style videos. arXiv preprint arXiv:1906.03539, 2019. 1, 2

[45] Haithem Turki, Vasu Agrawal, Samuel Rota Bulo,\` Lorenzo Porzi, Peter Kontschieder, Deva Ramanan, Michael Zollhofer, and Christian Richardt. Hybridnerf: Efficient neu- Â¨ ral rendering via adaptive volumetric surfaces. In CVPR, 2024. 1

[46] Matias Turkulainen, Xuqian Ren, Iaroslav Melekhov, Otto Seiskari, Esa Rahtu, and Juho Kannala. Dn-splatter: Depth and normal priors for gaussian splatting and meshing. In WACV, 2025. 2

[47] Jonathan Ventura. Structure from motion on a sphere. In ECCV, 2016. 6, 8

[48] Bennett Wilburn, Neel Joshi, Vaibhav Vaish, Eino-Ville Talvala, Emilio Antunez, Adam Barth, Andrew Adams, Mark Horowitz, and Marc Levoy. High performance imaging using large camera arrays. ACM TOG, 24(3):765â776, 2005. 2

[49] Linning Xu, Vasu Agrawal, William Laney, Tony Garcia, Aayush Bansal, Changil Kim, Samuel Rota Bulo, Lorenzo \` Porzi, Peter Kontschieder, Aljaz Bo Ë ziË c, Dahua Lin, Michael Ë Zollhofer, and Christian Richardt. Vr-nerf: High-fidelity vir- Â¨ tualized walkable spaces. In SIGGRAPH Asia, 2023. 1, 2

[50] Chen Yang, Peihao Li, Zanwei Zhou, Shanxin Yuan, Bingbing Liu, Xiaokang Yang, Weichao Qiu, and Wei Shen. Nerfvs: Neural radiance fields for free view synthesis via geometry scaffolds. In CVPR, 2023. 1

[51] Jianing Yang, Alexander Sax, Kevin J. Liang, Mikael Henaff, Hao Tang, Ang Cao, Joyce Chai, Franziska Meier, and Matt Feiszli. Fast3r: Towards 3d reconstruction of 1000+ images in one forward pass. In CVPR, 2025. 8

[52] Lihe Yang, Bingyi Kang, Zilong Huang, Zhen Zhao, Xiaogang Xu, Jiashi Feng, and Hengshuang Zhao. Depth anything v2. In NIPS, 2024. 3, 8

[53] Vickie Ye, Ruilong Li, Justin Kerr, Matias Turkulainen, Brent Yi, Zhuoyang Pan, Otto Seiskari, Jianbo Ye, Jeffrey Hu, Matthew Tancik, et al. gsplat: An open-source library for gaussian splatting. JMLR, 26(34):1â17, 2025. 6

[54] Zehao Yu, Jia Zheng, Dongze Lian, Zihan Zhou, and Shenghua Gao. Single-image piece-wise planar 3d reconstruction via associative embedding. In CVPR, 2019. 4

[55] Zehao Zhu, Zhiwen Fan, Yifan Jiang, and Zhangyang Wang. Fsgs: Real-time few-shot view synthesis using gaussian splatting. In ECCV, 2025. 2

[56] Matthias Zwicker, Hanspeter Pfister, Jeroen Van Baar, and Markus Gross. Ewa splatting. IEEE TVCG, 8(3):223â238, 2002. 3