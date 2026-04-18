# EntropyGS: An Efficient Entropy Coding on 3D Gaussian Splatting

Yuning Huang, Jiahao Pang, Fengqing Zhu, Dong Tian

## Abstract

As an emerging novel view synthesis approach, 3D Gaussian Splatting (3DGS) demonstrates fast training/rendering with superior visual quality. The two tasks of 3DGS, Gaussian creation and view rendering, are typically separated over time or devices, and thus storage/transmission and finally compression of 3DGS Gaussians become necessary. We begin with a correlation and statistical analysis of 3DGS Gaussian attributes. An inspiring finding in this work reveals that spherical harmonic AC attributes precisely follow Laplace distributions, while mixtures of Gaussian distributions can approximate rotation, scaling and opacity. Additionally, harmonic AC attributes manifest weak correlations with other attributes except for inherited correlation from a color space. A factorized and parameterized entropy coding method, EntropyGS, is hereinafter proposed. During encoding, distribution parameters of each Gaussian attribute are estimated to assist their entropy coding. The quantization for entropy coding is adaptively performed according to Gaussian attribute types. EntropyGS demonstrates about 30Ã rate reduction on benchmark datasets while maintaining similar rendering quality compared to input 3DGS data, with a fast encoding and decoding time.

## 1. Introduction

Novel View Synthesis (NVS) is a computer graphics task aimed at generating images from novel viewpoints in applications like virtual reality, 3D reconstruction, and gaming. By introducing Gaussians as primitives, 3D Gaussian Splatting (3DGS) [12] effectively represents both the geometry and texture information of a 3D scene. A Gaussian primitive is composed of position, rotation, opacity, scaling, and spherical harmonics to capture view-dependent color. With its highly parallelized design and advancements in GPU technology, 3DGS achieves significantly faster training and rendering times than the Neural Radiance Field (NeRF) [17] framework, while delivering competitive visual quality. However, the high data rate of Gaussian primitives poses a significant challenge to the transmission/storage of 3DGS model, when its training and rendering are separated over time or devices.

<!-- image-->  
Figure 1. Our proposed EntropyGS offers a noticeable memory reduction of approximately 30Ã compared to 3DGS [12], while maintaining high rendering quality. Additionally, the encoding and decoding times are kept under 5 seconds for scenes such as âRoomâ from the Mip-NeRF 360 dataset [4].

The attempt toward efficient encoding of 3DGS into a bitstream could be differentiated depending on whether offline updating of 3DGS Gaussians is allowed. For applications where offline updating of Gaussians is feasible, a global optimization across Gaussian creation/updating and compression is applied [5, 18, 21]. It provides more potential for compression while requiring additional offline processing to update Gaussians. For applications where low latency is a priority or offline processing is not affordable, the Gaussian primitives, as a pre-generated 3DGS model, are encoded into a bitstream as they are. Hence, compression-specific studies with a limited scope have their own merit [8]. This is how our work is positioned.

Many neural network (NN) model compression techniques, e.g., model parameter quantization, pruning [2, 9] and knowledge distillation [3, 11], are leveraged for 3DGS compression. However, unlike our proposal, in those works, neither the physical significance, nor the distinct statistical characteristics, of Gaussian attributes (position, rotation, .., spherical harmonics) is well counted. Those 3DGS compression works are aligned with general NN model compression methodologies.

We start with the analysis of the statistical properties of 3DGS attributes. Based on the theoretical induction and empirical verification, we reveal the weak correlation between spherical harmonic AC attributes, except for the inherited correlation in the color space. The discovery provides a solid motivation for our proposed factorized entropy coding design.

Additionally, for each attribute, we reveal that their statistics have a strong coherence with a common distribution type, e.g., Gaussian or Laplace. It leads to the proposed entropy coding depending on statistical estimation without counting on learning-based methods. Consequently, we propose an entropy coding method for 3DGS, named as EntropyGS, a factorized and parameterized design. It is novel and efficient with statistical coherence being fully explored for the first time in literature.

Main contribution of our work is summarized as follows:

1. A factorized design is proposed to entropy encode 3DGS based on a correlation analysis of Gaussian attributes that indicates a weak correlation in particular between spherical harmonic AC components.

2. A parameterized design is further proposed using common distributions to govern Gaussian attributes, including rotation, scaling, opacity, spherical harmonic AC.

3. An adaptive quantization finally completes the design of entropy encoder EntropyGS for pre-generated 3DGS models with competitive rate-distortion performance.

## 2. Related Works

For different applications depending on whether offline updating Gaussian primitives is permitted, existing 3DGS encoding can be categorized into two classes: joint optimization and compression, and compression-specific methods.

Methods in the former class demonstrate more compression capability as they allow further end-to-end optimization. Methods in the latter class, however, implement low latency and no alteration of 3DGS representations.

## 2.1. Joint Optimization and Compression

For methods in this category, the 3DGS Gaussian generation process is typically updated by counting the data rate required for 3DGS compression as an additional loss term. In addition, they may alter the original Gaussian representation by augmenting it with other formats, for example, 3D mesh [6] and even interpolators based on MLP [21]. Such modifications should be careful for applications such as scene editing and interactive rendering.

On top of ScaffoldGS [21], an anchor-based representation instead of the original 3DGS representation is adopted in HAC [5] for a joint optimization and compression. It introduces a compression framework designed to reduce the memory footprint of Scaffold-GS by introducing a binary hash grid and associated context-based modeling.

SOG [18] proposes another modified Gaussian representation. The parameters of 3D Gaussian Splatting (3DGS) are arranged onto a 2D grid, then a joint optimization and compression is conceived that promotes local homogeneity.

However, the sorting required for a 3D-to-2D mapping results in a high encoding time.

Pruning and subsequent optimization [1, 8, 22] are also commonly used techniques in existing works for reducing the rate of 3DGS. Various pruning strategies may be employed to decide which Gaussian primitives to be pruned, e.g., based on their impact on the rendering quality. Such pruning is typically harmonized with 3DGS Gaussian generation, hence they fall in the study of joint optimization and compression.

## 2.2. Compression-specific Study

For scenarios where low latency is a priority, the generation of 3DGS model and its compression have to be disentangled. Compression-specific studies target to encode a pregenerated 3DGS model. The creation of 3DGS model is an upstream and offline task for compression-specific methods.

A representative work in LightGaussian [8] introduces techniques used in neural network model compression, including vector quantization, knowledge distillation, to compress the original 3DGS model. C3DGS [19] proposes sensitivity-aware vector clustering with quantization-aware training. MesonGS [22] replaces rotation quaternion with Euler angles and applies region adaptive hierarchical transform (RAHT) [14] to encode key attributes.

Entropy coding is an essential step for data compression, as well as 3DGS compression. HAC [5] estimates distribution parameters using an overfitted MLP to perform entropy coding for 3DGS model.

Our work falls into a study about efficient entropy coding. In contrast to the literature, our method employs a parameterized design based on the identified distribution models. The distinction of our method lies in the design based on statistical estimation that is much more lightweight than a learning-based method.

## 3. Statistical Analysis of 3DGS Attributes

This section provides an analysis of the 3DGS attributes, which inspires our proposal for an efficient 3DGS compression. Gaussian attributes are partitioned into six distinct groups hereinafter: geometry, rotation, scaling, opacity, SHDC for first-order spherical harmonic coefficients, SHAC for higher-order harmonic coefficients.

## 3.1. Correlation Analysis

We characterize the correlation analysis into two categories: intra correlation within SHAC coefficients and inter correlation between SHAC and other attributes, including rotation, scaling, opacity, SHDC.

For intra correlation within the SHAC channels, the orthogonality of spherical harmonics ensures that each component (or coefficient) is independent by construction. For inter correlation, the relationship between SHAC and other attributes, no strong correlations are expected because of their distinct physical meaning. In conclusion, mathematical independence theoretically results in zero intra correlation and conceptual independence leads to negligible intercorrelation.

<!-- image-->  
(a) SHAC-SHAC, R

<!-- image-->  
(b) SHAC-SHAC, G

<!-- image-->  
(c) SHAC-SHAC, B

<!-- image-->  
(d) SHAC-(Rotation, Scaling, Opacity, SHDC)  
Figure 2. Mutual Information heatmap of âbicycleâ from Mip-NeRF 360 dataset. The first row shows the intra-correlation within SHAC, second row shows the inter-correlation between SHAC and the other Gaussian attributes

Minor correlation may be introduced during the Gaussian creation process. However, both intra correlation and inter correlation are assumed to be minor in this work.

Note that correlation from color space will be carried over between corresponding spherical harmonic coefficients. It is subject to future work how to utilize them for entropy coding.

Metric for measuring the correlation: We use Normalized Mutual Information (NMI) as the metric to evaluate the correlation. NMI quantifies the amount of shared information between two variables, hence capturing the general correlation (both linear and non-linear).

The Normalized Mutual Information (NMI) between two random variables X and Y , given their pmf (histogram), can be computed using the following formula:

$$
\operatorname { N M I } ( X , Y ) = { \frac { 2 \cdot I ( X ; Y ) } { H ( X ) + H ( Y ) } }
$$

where:

$I ( X ; Y )$ : The mutual information between X and $Y \colon$

$$
I ( X ; Y ) = \sum _ { x \in X } \sum _ { y \in Y } p ( x , y ) \log { \frac { p ( x , y ) } { p ( x ) p ( y ) } } .
$$

Here:

$p ( x , y )$ : Joint pmf of X and Y .

$p ( x ) { \mathrm { : } }$ : Marginal pmf of $\begin{array} { r } { X , p ( x ) = \sum _ { y } p ( x , y ) } \end{array}$

$p ( y ) { \mathrm { : } }$ : Marginal pmf of $\begin{array} { r } { Y , p ( y ) = \sum _ { x } ^ { ^ { \circ } } p ( x , y ) } \end{array}$

â¢ H(X): The entropy of X, defined as:

$$
H ( X ) = - \sum _ { x \in X } p ( x ) \log p ( x )
$$

$H ( Y )$ : The entropy of Y , defined similarly:

$$
H ( Y ) = - \sum _ { y \in Y } p ( y ) \log p ( y )
$$

The result is a value between 0 and 1: $\mathbf { N M I } ( X , Y ) = 1$ indicates perfect correlation, ${ \bf N M } ( X , Y ) = 0$ indicates no mutual correlation.

The normalized mutual information heatmap for a representative scene is shown in Fig. 2. From the first row of the figure, a weak intra-correlation is observed. The second row of the figure has verified that no inter-correlation exists between SHAC and other attributes. Please note that all tested scenes have shown the same trend, please see the full results for other scenes in the supplementary.

The observed weak correlation provides a solid support for a factorized entropy model design, where we can treat each channel of Gaussian attributes independently. Such design presents high efficiency, flexibility, and can be easily optimized for a parallel computation platform to achieve fast encoding and decoding time.

<!-- image-->  
(a) Geometry

<!-- image-->  
(b) Rotation

<!-- image-->  
(c) Scaling

<!-- image-->  
(d) Opacity

<!-- image-->  
(e) SHDC

<!-- image-->  
(f) SHAC

Figure 3. Example histograms of Gaussian attributes and estimated distribution (red curve) from the âBicycleâ scene in the Mip-NeRF datasets. Each plot is related to one channel from the respective attribute group. We do not estimate the distribution for Geometry and SHDC. Note that similar statistical behavior is observed for other scenes across different datasets.  
<!-- image-->  
Figure 4. Sensitivity comparison

During analysis, we find the correlation between Gaussian attributes is stronger for close Gaussian primitives, this is reasonable as local similarity is expected. However, efficiently incorporating this correlation is challenging (KNN needed) and would break the factorized design of our entropy model; hence, we consider it out of scope.

## 3.2. Governing Distributions for 3DGS attributes

We hereby analyze the statistical behavior of 3DGS attributes, i.e., geometry, rotation, scaling, opacity, and both the DC and AC components of the spherical harmonics (SH). Sample histograms and estimated distributions are presented in Fig. 3. Beyond this specific example, we observe consistent statistical behavior across all scenes in the benchmarking datasets.

Empirical results across diverse datasets reveal distinct statistical characteristics for each attribute group:

â¢ Geometry: Exhibits a highly dynamic range and sparsity, with no clear alignment to commonly-used distributions;

â¢ Rotation/Scaling/Opacity: Generally follows a simple Gaussian Mixture Model with fewer than four components, and in many cases can be approximated by a single Gaussian distribution;

â¢ SHDC: Does not conform to any common distributions and manifests smaller peaks at both extremes, corresponding to overexposed or underexposed pixels;

â¢ SHAC: Conforms closely to a Laplace distribution.

We also conduct an empirical study to verify the agreement between the Gaussian attributes and the associated probability distributions mentioned above. Particularly, Shannon entropy [20] of quantized Gaussian attributes is calculated based on their histogram and compared to the actual bits per sample (bps) achieved by our estimation, as shown in Tab. 1. Since Shannon entropy represents the theoretical minimum code length for lossless coding, from Tab. 1, we see that by parameterizing the distributions of Gaussian attributes with estimated distributions, trivial coding overhead can be achieved. This observation demonstrates the near-optimal precision of applying commonly used distributions to characterize the Gaussian attribute statistics.

These statistical insights are foundational to our compression method. The strategy is straightforward: for rotation, scaling, opacity, and SHAC, we estimate their distribution parameters using maximum likelihood estimation (MLE) or expectation-maximization (E-M). For Geometry and SHDC, we combine them as a point cloud with color attributes, followed by applying an off-the-shelf point cloud compression method to it.

<table><tr><td>Attribute</td><td>Q</td><td>Entropy</td><td>Actual</td><td>Overhead (%)</td></tr><tr><td>Rotation</td><td>8</td><td>6.243</td><td>6.261</td><td>0.29</td></tr><tr><td>Scaling</td><td>8</td><td>6.769</td><td>6.775</td><td>0.09</td></tr><tr><td>Opacity</td><td>8</td><td>6.337</td><td>6.342</td><td>0.08</td></tr><tr><td>SHAC</td><td>4</td><td>2.436</td><td>2.446</td><td>0.41</td></tr></table>

Table 1. Verify the agreement between the true data distribution and estimated distribution. The results are averaged on Mip-Nerf 360, Q means quantization depth (discussed in Sec 4.3)

## 3.3. Quantization Sensitivity

Our entropy coding method relies on quantization to obtain discrete representations. Thus, it is essential to investigate each attribute groupâs sensitivity to quantization errors. Please note that the quantization used in this work is for entropy coding only, as defined in information theory. It is different from âquantizationâ mentioned in previous works where it indicates the reduced precision for neural network parameters and computation.

We examine the impact of quantization across various Gaussian attributes by analyzing the rendering degradation relative to error magnitude (see Fig. 4). Normalized quantization error is calculated by scaling the mean-squared error (MSE) by the average value of each attribute group. Our study reveals substantial variability in quantization sensitivity: geometry is the most sensitive while SHAC exhibits the least sensitivity. This insight inspires an adaptive quantization strategy to optimize the rate-distortion tradeoff. The approach is straightforward: apply finer quantization steps to more sensitive attribute groups and coarser steps to less sensitive ones.

Furthermore, given that geometry is highly sensitive while SHAC is the least sensitive and yet consumes the most memory (76.3%), they deserve additional treatment. As to be seen in the next section, for geometry, we focus on reducing sensitivity and minimizing PSNR degradation. For SHAC, we aim to achieve a smaller quantization depth to maximize memory savings.

## 4. EntropyGS for Gaussian Splatting Coding

## 4.1. Overview of Coding Pipeline

The overall coding pipeline consists of two distinct stages as illustrated in Fig. 5.

The pipeline is invoked with a preparation stage, that is shared with earlier approaches. Here, the pre-generated Gaussian model undergoes refinement through statisticguided pruning and subsequent optimization to get more compression-friendly Gaussians.

The second stage, our primary contribution called EntropyGS, constitutes the core of the compression process. EntropyGS performs adaptive quantization and entropy coding, leveraging statistical distribution estimations.

It is important to highlight that EntropyGS is designed as an independent plug-in module. Its operation is not limited by the design of the preparation stage, allowing it to be flexibly applied to pre-generated 3DGS models with or without prior pruning and optimization.

## 4.2. Preparation with Pruning and Optimization

During the preparation stage, redundant Gaussians are removed by pruning, and then the quantized Gaussians are updated to compensate for the rendering quality loss caused by pruning. We have adopted the same pruning strategy proposed by LightGaussian [8] with small modifications to be presented next. In particular, the pruning is composed of two steps.

â¢ Pruning based on the importance level; and

â¢ Pruning based on the geometry attribute.

The importance-based pruning step directly applies the approach from LightGaussian [8] for its simplicity and effectiveness. Once the importance level of each Gaussian primitive is determined, we apply a threshold $\theta _ { 1 }$ (in %) and remove less important Gaussians according to this value.

Driven by the observation from sensitivity analysis in Section 3.3, we propose a geometry-based pruning strategy to eliminate Gaussians that are hard to encode yet with little contribution to rendering. Specifically, Gaussians with geometry values far away from the scene center are pruned based on the following strategy: prune the top $\theta _ { 2 }$ (in %) of Gaussians with the highest absolute values for each direction $( x , y , z )$ . Note that the $\theta _ { 2 }$ is deliberately set small to avoid removing potentially meaningful Gaussians.

After pruning, the remaining number of Gaussians is:

$$
N _ { p } = N _ { o } \cdot ( 1 - \theta _ { 1 } \% ) \cdot ( 1 - \theta _ { 2 } \% ) ^ { 3 }\tag{1}
$$

where $N _ { o }$ represents the number of initial Gaussians.

For post-pruning optimization, we first leverage SHAC Laplace distribution characteristics to rectify their values. This aims to scale down the range of SHAC values, thereby reducing the error introduced by subsequent min-max quantization. Please see the details in the supplementary.

Next, to compensate for the quality loss caused by pruning, an additional optimization step is required, adding approximately 20% training overhead compared to the original 3DGS training. This overhead is considered acceptable for offline processing, especially when compared to the 170% overhead introduced by joint methods like HAC.

The preparation stage primarily serves as a test condition to ensure the Gaussians to be encoded in experiments are meaningful, which is a common practice in the literature. If additional optimization is not allowed, EntropyGS can still be applied to the pre-generated 3DGS.

<!-- image-->  
Figure 5. Overview of our compression pipeline. Note that the complete decoding process is represented by one block in the figure due to space limit, the decoding process is symmetric with the encoding process. The first stage, Preparation, is optional in the pipeline. If no additional optimization is permitted in practice, the EntropyGS stage can be directly applied to the pre-generated Gaussians.

## 4.3. Factorized Entropy Coding with EntropyGS

After the preparation phase, we compress the refined Gaussians with EntropyGS, which efficiently utilizes the statistical properties of Gaussian attributes.

We first quantized each group of Gaussian attributes with the quantization depth based on its sensitivity. The quantization is applied separately for each channel within one group (e.g. 4 channels in the Rotation group).

The quantization method applied to all attributes except for SHAC is a simple min-max uniform quantization:

$$
q ( x ) = \mathrm { r o u n d } \left( \frac { \left( x - v _ { \mathrm { m i n } } \right) \cdot ( L - 1 ) } { v _ { \mathrm { m a x } } - v _ { \mathrm { m i n } } } \right)\tag{2}
$$

where x an entry of the channel to be quantized, $v _ { \mathrm { m i n } }$ and $v _ { \mathrm { m a x } }$ are the channelâs minimum and maximum values, and L is the number of quantization levels. Note that $L = 2 ^ { \mathrm { Q } }$ for a specific quantization depth Q.

We model the distributions of rotation, scaling, and opacity using Gaussian Mixture Models of up to four components. Note that this is also done separately for each channel within a group. The Expectation-Maximization (EM) algorithm [7] is used to estimate the probability, mean, and variance for each component in an iterative manner. With the number of components N limited to 4, the EM algorithm can be executed efficiently.

<table><tr><td rowspan="2"></td><td colspan="3">Quantization Depth</td></tr><tr><td>Attributes Ours-L</td><td>Ours-M</td><td>Ours-S</td></tr><tr><td>Geometry</td><td>17</td><td>16</td><td>15-16</td></tr><tr><td>Rotation</td><td>8</td><td>8</td><td>7</td></tr><tr><td>Scaling</td><td>8</td><td>8</td><td>7</td></tr><tr><td>Opacity</td><td>8</td><td>8</td><td>7</td></tr><tr><td>SHDC</td><td>8</td><td>8</td><td>8</td></tr><tr><td>SHAC</td><td>45</td><td>34</td><td>24</td></tr></table>

Table 2. Quantization Depth for different coding configurations.

For AC coefficients, Laplace distribution is used to model their values. We use maximum likelihood estimation (MLE) to determine the Laplace distribution parameters:

$$
\mu = \mathrm { m e d i a n } ( x ) , \quad b = { \frac { 1 } { N } } \sum _ { i = 1 } ^ { N } | x _ { i } - \mu |\tag{3}
$$

where $\mu$ is the location and b is the scaling parameter. The Laplace nature of the AC coefficients is a significant and interesting finding. Though out of the scope of this work, we hypothesize that this may stem from the L1-loss-based optimization used in 3DGS [12].

Following quantization and distribution estimation, we calculate the probability for each quantization interval to form the probability mass function (PMF). This PMF is then used by an Arithmetic Coding algorithm like [16] to achieve lossless compression.

For the geometry and SHDC groups, we avoid fitting a commonly used distribution. Instead, we encode these attributes using a point cloud codec. Specifically, we employ the efficient G-PCC codec from the MPEG PCC standard1. It treats the Gaussians with geometry and SHDC attributes as a color point cloud. Note a learning-based point cloud compressor can also be directly applied here.

## 4.4. Rate Control

In our method, achieving different rates (model sizes) is straightforward and requires no additional training. It is achieved by simply adjusting the quantization depths applied to various groups of Gaussian attributes.

## 5. Experimentation

## 5.1. Experiment Settings

The proposed method is evaluated on Mip-NeRF 360 [4], Tank & Temples [13], and Deep Blending [10].

Our approach is compared against four recent 3DGS compression methods published in leading venues: LightGaussian [8], C3DGS [19], CompactGS [15], MesonGS [22]. Recall the categorization of 3DGS coding illustrated in Section 2, the selected methods are compression-specific methods that focus on the compression of pre-generated 3DGS scene without joint optimization, where heavy additional training is not feasible. On the other hand, HAC [5] and SOG [18], as joint methods, have demonstrated excellent rate-distortion performance. However, these joint methods are not aligned with our scope, there they are not included for direct comparison (see supplementary for more information).

<!-- image-->  
(a) Comparison on Mip-NeRF 360 Dataset

<!-- image-->  
(b) Comparison on Tank & Temples Dataset  
Figure 6. Performance comparison across datasets for different methods, upper right is better

It is important to note that different baseline methods listed above have adopted different pre-generated 3DGS models, which results in variations in pre-compression metrics. For example, LightGaussian reported using a 3DGS with a PSNR of 27.53 dB on the Mip-NeRF dataset, compared to the original 3DGS [12] PSNR of 27.28 dB. Therefore, to ensure a fair comparison, we focus on the metric differences between the compressed and uncompressed model results reported by each baseline method. For instance, the PSNR difference is defined as:

$$
\Delta \mathrm { P S N R } = \mathrm { P S N R } _ { c } - \mathrm { P S N R } _ { o }\tag{4}
$$

where $\mathrm { P S N R } _ { c }$ is the PSNR after compression and PSNRo is the PSNR before the compression.

The difference in PSNR (or SSIM/LPIPS) indicates the rendering quality loss due to compression. The interpretation of them follows the original metricâs trend: for âPSNR and âSSIM, higher values mean better quality, while for âLPIPS, lower values mean better quality. Typically, this difference (for PSNR/SSIM) is negative, representing a quality downgrade after compression. However, since additional optimization is applied, the difference can be positive, meaning the quality is improved.

## 5.2. Implementation Details

All our experiments were conducted on NVIDIA RTX 3090 and Intel 11700K, using the pre-generated models from the official repository of the 3DGS paper [12] instead of retraining on our platform. For the hyperparameter setting, we categorize scenes into two groups: indoor and outdoor. The same processing strategy is applied to all scenes within each group, demonstrating the adaptivity of our method, i.e., no scene-specific configurations are required. See the settings for the pruning and optimization stage in the supplementary.

Based on the described rate control method, we introduce three coding configurations of EntropyGS: EntropyGS-L, EntropyGS-M, and EntropyGS-S, corresponding to large, medium, and small bitstream sizes, respectively. See Tab. 2 for details. All configurations are applied to the same 3DGS output from the preparation stage.

## 5.3. Main Results

In Tab. 3 and Fig. 6, we evaluate our method alongside other 3DGS compression methods, note that in the table, we only show the result of EntropyGS-M to facilitate the comparison. Experiments were conducted on the Mip-NeRF and Tank & Temples datasets, as some baseline methods do not report results for the Deep Blending dataset.

Our method achieves a significantly smaller model size across all datasets, effectively reducing storage requirements. Despite this compression, EntropyGS maintains comparable or improved PSNR values, particularly in the Large configuration, which shows minimal visual quality degradation. The flexibility of the rate control method enables a tradeoff between compression and rendering quality, making our approach ideal for applications that demand flexibility.

Comparisons with these baselines indicate that EntropyGS consistently outperforms them on these two benchmarks. For example, it achieves both higher âPSNR and compression ratio compared to all baseline methods. The competitive performance of EntropyGS demonstrates the effectiveness of our proposal, which combines distribution estimation, adaptive quantization, and entropy coding, guided by an analysis of 3DGS properties.

Furthermore, EntropyGS achieves competitive performance with a streamlined, low-complexity design, unlike baseline methods that require trainable modules such as the codebook for vector quantization or neural networks for probability estimation. This streamlined design provides flexible and transparent control over the trade-off between rendering quality and compression ratio and can be easily optimized for specific hardware configurations.

<table><tr><td></td><td colspan="4">Mip-NeRF 360</td><td colspan="4">Tank &amp; Temples</td></tr><tr><td>Method</td><td>âPSNR â</td><td>ÎSSIMâ</td><td>âLPIPSâ</td><td>Ratio*â</td><td>ÎPSNR â</td><td>âSSIMâ</td><td>âLPIPSâ</td><td>Ratio*â</td></tr><tr><td>3DGS [12]</td><td>-</td><td>-</td><td>-</td><td>-</td><td>-</td><td>-</td><td>-</td><td>-</td></tr><tr><td>LightGaussian [8]</td><td>-0.25</td><td>-0.005</td><td>0.016</td><td>17.24Ã</td><td>0</td><td>-0.005</td><td>0.012</td><td>17.27Ã</td></tr><tr><td>C3DGS [19]</td><td>-0.23</td><td>-0.014</td><td>0.024</td><td>26.23Ã</td><td>-0.04</td><td>-0.009</td><td>0.011</td><td>23.26Ã</td></tr><tr><td>MesonGS [22]</td><td>-0.37</td><td>-0.009</td><td>0.013</td><td>23.23Ã</td><td>-0.04</td><td>-0.001</td><td>0.006</td><td>24.83Ã</td></tr><tr><td>CompactGS [15]</td><td>-0.38</td><td>-0.014</td><td>0.025</td><td>15.28Ã</td><td>-0.39</td><td>-0.014</td><td>0.023</td><td>10.96Ã</td></tr><tr><td>EntropyGS (Ours)-M</td><td>-0.04</td><td>-0.007</td><td>0.012</td><td>28.25Ã</td><td>0.15</td><td>-0.005</td><td>0.013</td><td>27.56Ã</td></tr></table>

Table 3. Comparison of methods on Mip-NeRF 360 and Tank & Temples Datasets. The best results overall are bolded in each metric, and the second-best results are underlined. Our method achieves a significantly higher PSNR while offering the highest compression ratio. \*The ratio denotes compression ratio (the original model size divided by the model size after compression)

<table><tr><td></td><td colspan="2">CPU coding time</td><td colspan="2">GPU coding time</td></tr><tr><td>Method</td><td>Encoding</td><td>Decoding</td><td>Encoding</td><td>Decoding</td></tr><tr><td>EntropyGS (Ours)-M</td><td>16.4s</td><td>13.8s</td><td>3.6s</td><td>0.2s</td></tr></table>

Table 4. CPU and GPU coding time averaged on Mip-NeRF 360

In terms of encoding and decoding complexity, it is worth noting that only two methods, C3DGS (5 minutes) and MesonGS (1 minute), have reported encoding times in their respective papers on GPU platform. We report both the encoding and decoding time in Tab. 4. As expected, our method demonstrates a significantly faster encoding and decoding time, which is due to the factorized entropy model design and learning-free statistical distribution estimation.

## 5.4. Ablation Studies

<table><tr><td>Method</td><td>PSNR</td><td>Size (MB)</td></tr><tr><td>Original 3DGS</td><td>27.28</td><td>760.1</td></tr><tr><td>+ Importance Pruning</td><td>25.54</td><td>266.0</td></tr><tr><td>+ Geometry Pruning</td><td>25.45</td><td>264.4</td></tr><tr><td>+ Optimization</td><td>27.42</td><td>264.4</td></tr><tr><td>+ Quantization</td><td>27.24</td><td>41.5</td></tr><tr><td>+ Entropy Coding</td><td>27.24</td><td>32.2</td></tr><tr><td>+ G-PCC</td><td>27.24</td><td>26.9</td></tr></table>

Table 5. Ablation Study: how each step in the pipeline influences the rendering quality and size of 3DGS, tested on Mip-NeRF360

In this section, we examine the effectiveness of each step proposed in the method and how they contribute to the final performance (See Tab. 5), in this experiment, the EntropyGS-M setting is used.

The pruning of 3DGS primitives initially reduces model size while causing some rendering quality loss. However, the subsequent post-optimization effectively restores the quality and even slightly improves PSNR. Our proposed geometry pruning has minimal immediate impact, as only a small percentage of Gaussians are pruned, but this step helps lower quantization errors in later stages.

Applying adaptive quantization to different attribute groups within 3DGS further reduces the model size, though it introduces some rendering quality degradation due to quantization error. The following entropy coding compresses the quantized values further in a lossless manner. Entropy coding is not applied to the geometry or SHDC attributes. Instead, we use the standard G-PCC point cloud codec in lossless mode to encode these components, achieving the smallest model size. Notably, the combination of quantization, entropy coding and point cloud coding alone achieves a 10Ã compression ratio without requiring any additional training (e.g., preparation stage mentioned before). This highlights the practical benefits of our proposed EntropyGS, which reduces the 3DGS model size by 10Ã while enabling fast encoding and decoding with no further optimization.

## 6. Conclusion

Motivated by a novel insight into the statistical characteristics of 3D Gaussian Splatting attributes, we introduce a simple yet effective compression scheme tailored for coding 3D Gaussian Splatting models. Experimental results demonstrate that our method achieves competitive compression performance while remaining both straightforward and computationally efficient. It is important to note that EntropyGS adopts a factorized entropy model, encoding each attribute channel independently. This design offers advantages in simplified probability estimation, reduced computational overhead, and enhanced scalability. While ratedistortion performance could be further improved by accounting for the underlying relationships between attributes other than SHAC, efficiently incorporating them is a nontrivial challenge, which we leave for future work.

## References

[1] Muhammad Salman Ali, Sung-Ho Bae Maryam Qamar, , and Enzo Tartaglione. Trimming the fat: Efficient compression

of 3d gaussian splats through pruning. arXiv preprint, 2024. 2

[2] Sajid Anwar, , and Wonyong Sung Kyuyeon Hwang. Structured pruning of deep convolutional neural networks. ACM Journal on Emerging Technologies in Computing Systems, 2017. 1

[3] Jimmy Ba, , and Rich Caruana. Do deep nets really need to be deep. Advances in neural information processing systems, 2014. 1

[4] Jonathan T. Barron, Dor Verbin Ben Mildenhall, , and Peter Hedman Pratul P. Srinivasan. Mip-nerf 360: Unbounded anti-aliased neural radiance fields. In Proceedings of the IEEE/CVF conference on computer vision and pattern recognition, 2022. 1, 6

[5] Yihang Chen, Weiyao Lin Qianyi Wu, , and Jianfei Cai Mehrtash Harandi. Hac: Hash-grid assisted context for 3d gaussian splatting compression. In European Conference on Computer Vision, 2025. 1, 2, 6

[6] Yonghan Lee Jaehoon Choi, Heesung Kwon Hyungtae Lee, and Dinesh Manocha. Adaptive mesh-aligned gaussian splatting for high-quality rendering. Asian Conference on Computer Vision, 2024. 2

[7] Arthur P. Dempster, , and Donald B. Rubin. Nan M. Laird. Maximum likelihood from incomplete data via the em algorithm. Journal of the Royal Statistical Society, 1977. 6

[8] Zhiwen Fan, Kairun Wen Kevin Wang, Dejia Xu Zehao Zhu, , and Zhangyang Wang. Lightgaussian: Unbounded 3d gaussian compression with 15x reduction and 200+ fps. Advances in Neural Information Processing Systems, 2024. 1, 2, 5, 6, 8

[9] Yang He, Xuanyi Dong Guoliang Kang, , and Yi Yang Yanwei Fu. Soft filter pruning for accelerating deep convolutional neural networks. arXiv preprint, 2018. 1

[10] Peter Hedman, True Price Julien Philip, George Drettakis Jan-Michael Frahm, , and Gabriel Brostow. Deep blending for free-viewpoint image-based rendering. ACM Transactions on Graphics, 2018. 6

[11] Geoffrey Hinton. Distilling the knowledge in a neural network. arXiv preprint, 2015. 1

[12] Bernhard Kerbl, Thomas Leimkuhler Georgios Kopanas, , Â¨ and George Drettakis. 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics, 2023. 1, 6, 7, 8

[13] Arno Knapitsch, Qian-Yi Zhou Jaesik Park, , and Vladlen Koltun. Tanks and temples: Benchmarking large-scale scene reconstruction. ACM Transactions on Graphics, 2017. 6

[14] Ricardo L, Chou De Queiroz, and Philip A. Compression of 3d point clouds using a region-adaptive hierarchical transform. IEEE Transactions on Image Processing, 25(8):3947â 3956, 2016. 2

[15] Joo Chan Lee, Xiangyu Sun Daniel Rho, , and Eunbyung Park Jong Hwan Ko. Compact 3d gaussian representation for radiance field. In Proceedings of the IEEE/CVF conference on computer vision and pattern recognition, 2024. 6, 8

[16] Fabian Mentzer, Michael Tschannen Eirikur Agustsson, , and Luc Van Gool. Radu Timofte. Practical full resolution learned lossless image compression. In Proceedings of

the IEEE/CVF conference on computer vision and pattern recognition, 2019. 6

[17] Ben Mildenhall, Matthew Tancik Pratul P. Srinivasan, Ravi Ramamoorthi Jonathan T. Barron, , and Ren Ng. Nerf: Representing scenes as neural radiance fields for view synthesis. Communications of the ACM, 2021. 1

[18] Wieland Morgenstern, Florian Barthel, Anna Hilsmann, and Peter Eisert. Compact 3d scene representation via selforganizing gaussian grids. In European Conference on Computer Vision, 2025. 1, 2, 6

[19] Simon Niedermayr, , and Rudiger Westermann Josef Â¨ Stumpfegger. Compressed 3d gaussian splatting for accelerated novel view synthesis. In Proceedings of the IEEE/CVF conference on computer vision and pattern recognition, 2024. 2, 6, 8

[20] Claude Elwood Shannon. A mathematical theory of communication. The Bell System Technical Journal, 1948. 4

[21] Tao, Yu Lu, Linning Mulin, Xu, Yuanbo, Wang, Xiangli, Dahua, Dai Bo Limin, and Lin. Scaffold-gs: Structured 3d gaussians for view-adaptive rendering. In Proceedings of the IEEE/CVF conference on computer vision and pattern recognition, 2024. 1, 2

[22] Shuzhao Xie, Chen Tang Weixiang Zhang, Rongwei Lu Yunpeng Bai, , and Zhi Wang Shijia Ge. Mesongs: Post-training compression of 3d gaussians via efficient attribute transformatio. In European Conference on Computer Vision, 2025. 2, 6, 8