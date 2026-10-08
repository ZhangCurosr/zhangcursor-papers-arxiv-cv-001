# Efficient 3D Gaussian Head Avatars for Edge Devices

Umar Farooq Jean-Yves Guillemaut Adrian Hilton Marco Volino CVSSP, University of Surrey

## Abstract

Generative 3D Gaussian head avatars provide highquality, efficient rendering, but synthesising the Gaussian representation remains computationally expensive, limiting deployment on resource-constrained and edge devices. We introduce an efficient generator architecture for unconditional 3D Gaussian head synthesis, based on a parameterefficient synthesis block and depth-wise separable convolutions while retaining style-based conditioning. Our architecture reduces generator complexity without requiring model compression or quantisation. Compared with the baseline model, our approach reduces FLOPs by 94%, parameter count by 70%, and model size by 81%, while maintaining competitive generation quality. Wefurther demonstrate practical CPU inference and browser-based execution on mobile devices using ONNX Runtime, enabling 3D Gaussian avatar synthesis without dedicated GPU hardware or applicationspecific software. In addition to conventional image-quality metrics, we evaluate multi-view consistency, training cost, and deployment performance. Code, trained models, and evaluation tools will be released publicly.

## 1. Introduction

Generating realistic animatable human avatars is a core research area within computer vision and graphics with extensive downstream applications in the creative industries, gaming, telecommunication, AR/VR and telepresence. Capturing high-quality human avatars in a studio setting using multiple cameras and depth sensors is expensive and timeconsuming. This has motivated significant research towards automated generation pipelines which can produce highquality avatars from a single image, multiple images, videos or synthesise novel head identities.

These models rely on large datasets [20] to learn useful priors about human geometry, movement and appearance. However, this is a challenging task and the generated avatars can often lack fine geometric details and multi-view consistency. For producing head avatars with random identities, Generative Adversarial Networks (GANs) [14] have been explored extensively. [6, 11, 42] use GANs with great success and recently NeRF-based [36] head avatar models have shown good results. However, NeRF-based representations suffer from slow rendering, which impacts both training and inference. Recent progress in 3D Gaussian Splatting [23] has made it possible to use a differentiable, explicit and fast 3D representation directly inside the training pipeline of a generative model. [24] has incorporated 3DGS to produce Gaussian head avatars which are fast to render at both training and inference time, and follow-up work has improved multi-view consistency and background separation [4] as well as introduced animation capabilities [13, 52].

![](images/aaf8caeae5a11259bd3dd4e3cb83576330f6b7a06d8c20249e1f90e27aa6d814.jpg)  
Figure 1. Overview of our efficient 3D Gaussian head-avatar synthesis pipeline and downstream applications. Our model can generate a novel 3D Gaussian avatar from a random latent code and it also supports subsequent animation and latent manipulation.

The adoption of 3DGS as a differentiable representation has substantially reduced the cost of rasterising avatars; however, generating the Gaussian representation itself remains computationally expensive. For unconditional head avatar synthesis, the generation pipeline dominates the compute cost and has to be run for every new identity. Recently, [13] has proposed efficient architectures for the animation pipeline for edge devices, however the initial synthesis step remains costly. This prevents the use of the full pipeline on resource-constrained and edge devices presenting a bottleneck for various applications. A lightweight generator capable of producing novel identities in a 3D-consistent manner would enable the complete synthesis pipeline to run on such devices. Furthermore, retaining style-based conditioning enables characteristics of the generated head to be modified at runtime, supporting downstream creative and interactive applications.

In this work, we propose a generator architecture that is efficient in terms of both parameter count and computational cost for inference on resource-constrained and edge devices. We reformulate modulation and demodulation for depth-wise separable convolutions and introduce a parameter-efficient Gaussian attribute output structure while retaining stylebased conditioning [21]. We demonstrate the performance of our model on commodity hardware and mobile devices inside a web browser with no application-specific software setup required.

In summary, we make the following contributions:

• We introduce a style-conditioned depth-wise separable synthesis architecture, including a reformulated modulation and demodulation mechanism, together with a parameterefficient Gaussian attribute output block.

• We produce a generator which is up to 70% smaller in parameter count and requires up to 94% fewer FLOPs, while retaining the original Gaussian output resolution and primitive count.

• We show that our method can be deployed on commodity hardware and resource-constrained devices, including browser-based inference on mobile phones.

## 2. Related Work

3D Aware Generative Head Models: 3D head avatar synthesis has been an active area of research, with NeRF [36] and GAN [14] based methods among the most popular approaches. Approaches using 2D diffusion models with score distillation sampling (SDS) have also been proposed [16, 39]. [6] introduced an early approach for direct synthesis of 3D head geometry, adopting the architecture from [21] and extending it to produce triplanes rendered using NeRF [36]. However, this increased the computational cost of both training and inference. Subsequent work reduced this cost through manifold [11, 51] or sparse voxel [42] representations, by imitating a 2D generator [8], and by extending coverage from the frontal hemisphere to the full head through the untied triplanes of PanoHead [2] and spherical parameterisation of SphereHead [27]. Next3D [43] demonstrated that expression, blink and gaze control can be learned from unstructured 2D images without video supervision. Another line of work uses multi-view diffusion [15, 44, 45], but suffers from high computational cost and limitations in multi-view consistency.

Recent work has incorporated 3DGS [23] as a replacement for NeRF-based rendering, with significant gains in training and inference speed. Gaussian Shell Maps [1] uses a 2D convolutional generator to predict Gaussian attributes in the texture space of a deformable template, allowing the generator to remain a standard image network while the template provides the geometric prior. GSGAN [18] instead organises the primitives hierarchically and supervises them adversarially. GGHead [24] applies the template-UV formulation to head avatars under a FLAME [29] parameterisation, regularising the geometry while retaining a standard 2D convolutional generator. CGS-GAN [4] removes view-conditioned generation that causes multi-view inconsistency in this class of model, reports strong generation quality, and introduces the $\mathrm { F I D } _ { 3 \mathrm { D } }$ metric. 3DGH [25] extends GGHead with separately composable hair and face generators, EGG3D [26] targets editability, and MVCHead [10] enforces multi-view consistency without explicit multi-view generation. Across these approaches, reported efficiency gains primarily concern rendering or training, while the cost of a generator forward pass remains relatively underexplored.

Animatable Gaussian Head Avatars: Animation of Gaussian head avatars is generally achieved by binding primitives to a deformable template. GaussianAvatars [40] follows this mechanism for per-subject reconstruction, while 3D Gaussian Blendshapes [33] expresses residual deformation in a linear basis, reducing inference-time animation to linear algebra. GAIA [52] uses a dual-generator architecture, with one generator producing shape and another expression-conditioned deformations, together with a separate expression-conditioned discriminator. AGORA [13] also uses a dual-generator approach but with a single discriminator taking the rendered image and an expression-coded vertex rendering. It introduces a smaller MLP-based vertex deformation model that approximates the larger expression generator, reducing runtime deformation cost. Our work instead addresses the synthesis of previously unseen identities and is therefore complementary to these deformation and animation approaches.

Efficient Generators and GAN Architectures: GAN Compression [28] introduced channel pruning under distillation for conditional generators, while Content-Aware GAN Compression [32] reported an elevenfold reduction in FLOPs for an unconditional StyleGAN2 alongside improved latent disentanglement. Anycost GANs [31] vary resolution and channel width at inference to provide multiple operating points from a single model. Other work directly improves the efficiency of the underlying 2D StyleGAN architecture [5, 19]. MobileStyleGAN [5] uses a wavelet-based generator and parameter-efficient convolutions, removing RGB heads from all but the final synthesis block. It also modulates and demodulates activations rather than weights and pairs depth-wise and point-wise convolutions, but it si based on 2D/wavelet operations. BlazeStyleGAN [19] instead retains RGB heads but uses variable-resolution feature maps to reduce computational cost. Crucially, both MobileStyleGAN [5] and BlazeStyleGAN [19] have RGB as the final output whereas our method is focused on producing Gaussian output with multiple channels and more structure.

Efficient Gaussian Representations: A parallel body of

![](images/22600c034947947b3e77ab98fdc0114b48d112feccb596d15bc75683d9061e85.jpg)  
Figure 2. Overview of our 3D Gaussian head-avatar generation pipeline.

## 3. Method

work compresses the Gaussians themselves rather than the network that generates them [3]. Compressed 3DGS [38] applies sensitivity-aware vector quantisation and entropy coding, LightGaussian [12] reduces spherical harmonic degree through distillation, and Self-Organizing Gaussian Grids [37] organise primitives into a two-dimensional grid for standard image codecs. These methods operate on primitives after optimisation and are complementary to reducing their generation cost. They could therefore be combined with our approach to further reduce storage requirements.

On-Device Inference: MobileNeRF [9] restructures a neural field for execution within the standard rasterisation pipeline of an unmodified browser, while SnapFusion [30] and Snap-Gen [7] reduce text-to-image diffusion models to mobile latency budgets. Measurement conditions are important when interpreting such results: [49] reports that browserbased deep learning inference can be substantially slower than native execution on the same mobile hardware. Our work builds on GGHead [24] due to its fast inference [4] and adoption as a baseline for animation pipelines [13, 52]. However, [4, 24] focus on performance within conventional GPUbased workflows rather than resource-constrained devices. AGORA [13] improves the animation pipeline for edge devices and demonstrates speed-ups within a web browser, but does not address the cost of initial identity synthesis. This remains a bottleneck for generating Gaussian head avatars from scratch and prevents on-the-fly modification and style mixing enabled by the StyleGAN2 [21] backbone. Our work addresses this complementary problem by reducing memory, compute and storage requirements of initial head avatar synthesis.

## 3.1. Preliminaries

3D Gaussian Splatting: 3D Gaussian Splatting [23] is an explicit representation for 3D scenes that uses a collection of 3D Gaussians to represent geometry and appearance. Each Gaussian is defined by its position $\mu ,$ scale s, rotation r, opacity α, and colour attributes c. The colour c of a pixel is determined by alpha-blending the contributions of N ordered Gaussians overlapping the pixel:

$$
c = \sum _ { i = 1 } ^ { N } c _ { i } \alpha _ { i } \prod _ { j = 1 } ^ { i - 1 } ( 1 - \alpha _ { j } )\tag{1}
$$

where $c _ { i }$ is the colour of the i-th Gaussian and $\alpha _ { i }$ is its opacity at the pixel location. The term $\textstyle \prod _ { j = 1 } ^ { i - 1 } ( 1 - \alpha _ { j } )$ represents the transmittance, accounting for the visibility of the i-th Gaussian. View-dependent appearance is represented using spherical harmonics, whose coefficients are evaluated according to the viewing direction.

Gaussian Attribute Maps: The attributes for each Gaussian are represented as a C-channel vector $a = [ \mu , r , s , \alpha , c ] ^ { \top } \in$ $\mathbb { R } ^ { C }$ in a UV map. Here $\mu , r , s \in \mathbb { R } ^ { 3 }$ represent position, rotation and scale respectively, $\alpha \in \mathbb { R }$ is the opacity, and $c \in \mathbb { R } ^ { d _ { c } }$ denotes colour attributes. We use $C = 1 3 ( d _ { c } = 3 )$ for our final model and $C = 2 2 \left( d _ { c } = 1 2 \right)$ for the variant incorporating view-dependent effects via first-degree spherical harmonics. The UV maps are generated at $U \bar { V } \in \bar { \mathbb { R } ^ { 2 5 6 \times 2 5 6 } }$ resolution by a StyleGAN2 backbone as a function of a latent code z and a camera pose $p ,$ where $p \in \mathbb { R } ^ { 2 5 }$ and $z \in \mathbb { R } ^ { 5 1 2 }$

FLAME Model: The FLAME (Faces Learned with an Articulated Model and Expressions) model [29] is a parametric model of facial shape, expression and pose. We use FLAME as a geometric prior for the generated Gaussian representation. The Gaussians are samlped over the mesh surface and a positional zero convolution is used to predict offsets. The zero convolution allows the Gaussians to be initialised near the mesh surface and to gradually learn their displacement. This provides a soft geometric regularisation that encourages consistent head geometry across views and poses. The complete pipeline is shown in Figure 2.

## 3.2. Architecture Overview

Generator Architecture: We start with a StyleGAN2-based generator representing the UV map as a function of camera pose $p ,$ latent code z and FLAME parameters. The FLAME parameters are also used by the expression branch and the discriminator, which is shown synthetic geometric cues to improve performance on expressions. The camera pose and latent code are fed to a mapping network $f ( p , z ) = w$ where w $\in \mathbb { R } ^ { 5 1 2 }$ . Here $f$ is a 2-layer MLP with 512 hidden units. The generator consists of $L$ synthesis blocks, where each block maps

$$
F _ { \ell } ( \mathrm { F e a t } _ { \mathrm { i n } } , { w _ { \ell } } , U V _ { \ell - 1 } ) = \mathrm { F e a t } _ { \mathrm { o u t } } , \mathrm { U V } _ { \mathrm { o u t } }\tag{2}
$$

Each synthesis block contains a feature layer and a Gaussian output layer whose outputs are accumulated to produce the final UV attribute map. The Gaussian output layer directly produces the Gaussian attribute channels, with a fixed output resolution for each block. To reduce the computational and parameter cost of the generator, we replace all normal convolution layers with depth-wise separable convolutions. A standard convolution $C ( W , x )$ can be implemented as a depth-wise convolution followed by a point-wise convolution:

$$
\mathcal { C } ( W , x ) = P ( W _ { p } , D ( W _ { d } , x ) )\tag{3}
$$

where $W _ { p }$ and $W _ { d }$ are the weights for the point-wise and depth-wise convolutions, respectively. This reduces the convolutional parameter count from:

$$
W = C _ { \mathrm { o u t } } \times C _ { \mathrm { i n } } \times K \times K
$$

to:

$$
\begin{array} { l } { { W _ { d } = C _ { \mathrm { i n . d } } \times K \times K } } \\ { { W _ { p } = C _ { \mathrm { o u t . p } } \times C _ { \mathrm { i n . p } } \times 1 \times 1 } } \end{array}
$$

where K is the kernel size and $C _ { \mathrm { i n . d } }$ and $C _ { \mathrm { i n . p } }$ are their input channel counts, respectively.

Modulation with Depth-wise Convolutions: Replacing standard convolutions with depth-wise separable convolutions requires modifying the modulation and demodulation process of the StyleGAN2 generator. In StyleGAN2, style modulation is applied to the convolution weights. For a convolution with weights $w _ { i j k }$ , where i indexes the input channels, j the output channels and k the $K ^ { 2 }$ spatial taps, the style vector s scales the input channels and the weights are then renormalised,

![](images/07bca21da323a813fa63f93054f85723edf13350482ed4d2dc2e39102ea76c77.jpg)  
Figure 3. Proposed architecture of the modulated convolution block with depth-wise separable convolutions. The modulation is applied to the instance normalised input feature map and the demodulation to the output of the point-wise convolution.

$$
w _ { i j k } ^ { \prime } = s _ { i } w _ { i j k } , \qquad w _ { i j k } ^ { \prime \prime } = \frac { w _ { i j k } ^ { \prime } } { \sqrt { \sum _ { i , k } ( w _ { i j k } ^ { \prime } ) ^ { 2 } + \epsilon } } .\tag{4}
$$

The normalising sum runs over the input channel axis as well as the spatial axis. Since different input channels are scaled by different values of $s _ { i } ,$ , no common factor can be taken out of the sum, and the modulation therefore remains dependent on the style vector.

This property does not hold for a depth-wise convolution. Each output channel of a depth-wise convolution is produced from a single input channel, so the input and output channel indices coincide, the weights reduce to $w _ { j k }$ , the style entry acting on channel $j$ is $s _ { j }$ , and the sum in Equation 4 is taken over k alone,

$$
\begin{array} { r } { \sigma _ { j } ^ { \mathrm { w } } = \sqrt { \sum _ { k } ( s _ { j } w _ { j k } ) ^ { 2 } + \epsilon } = \sqrt { s _ { j } ^ { 2 } \sum _ { k } w _ { j k } ^ { 2 } + \epsilon } . } \end{array}\tag{5}
$$

For small ϵ the scale can be taken out of the square root and the modulated and demodulated weights become

$$
w _ { j k } ^ { \prime \prime } = \frac { s _ { j } w _ { j k } } { | s _ { j } | \sqrt { \sum _ { k } w _ { j k } ^ { 2 } } } = \mathrm { s g n } ( s _ { j } ) \frac { w _ { j k } } { \sqrt { \sum _ { k } w _ { j k } ^ { 2 } } } .\tag{6}
$$

Thus, except for its sign, the style coefficient $s _ { j }$ cancels during demodulation, removing the magnitude of the style modulation from the depth-wise convolution. Applying the modulation to the point-wise convolution instead would pre serve the style dependence because the $1 \times 1$ convolution restores the sum over the input channels. However, the depthwise convolution runs first, so its spatial filtering would remain style-agnostic. Retaining a dense convolution solely for modulation would also undermine the computational benefit of the separable factorisation. We therefore apply the modulation to the input activations before the depth-wise convolution, and the demodulation to the output of the pointwise convolution,

$$
y = P \big ( W _ { p } , D ( W _ { d } , s \odot \tilde { x } ) \big ) , \qquad \hat { y } _ { j } = \frac { y _ { j } } { \sigma _ { j } } ,\tag{7}
$$

where x˜ is the instance normalised input and $\odot$ is a perchannel scaling. The demodulator $\sigma _ { j }$ is the norm of the composed separable kernel that produces output channel $j ,$ taken over the input channels i and the spatial taps k of the point-wise and depth-wise weights and scaled by the style,

$$
\begin{array} { r } { \sigma _ { j } = \sqrt { \sum _ { i , k } \left( s _ { i } W _ { p , j i } W _ { d , i k } \right) ^ { 2 } + \epsilon } . } \end{array}\tag{8}
$$

Because the point-wise stage restores the sum over $i ,$ no common factor can be taken out of Equation $^ { 8 , }$ and the cancellation of Equation 6 does not recur. The style therefore remains present in the composed depth-wise/point-wise operation while retaining the efficiency of separable convolution.

Weight demodulation was originally introduced to avoid normalizing the activations, which produced droplet artifacts in StyleGAN [21], so moving back to the data domain loses that property. To stabilise the adversarial training, we apply weight normalisation [41] to the convolution weights and instance normalisation [47] to the input feature maps. The bias and noise are added after demodulation and before the LeakyReLU activation function. Removing either normalization destabilised training in our experiments. The architecture of our modulated convolution block is shown in Figure 3.

Template Mesh Mapping: From the Gaussian attributes in the UV map, a set of 3D Gaussians is sampled for the rendering process. We use a layer on the produced $\mu$ with zero weight initialisation to initially place Gaussians exactly on the surface similar to [24]. This provides geometric regularisation and encourages consistent geometry across views and poses.

## 3.3. Generator Design

To further reduce FLOPs, we reduce the width of the intermediate feature channels to one-quarter and one-half of their original size for our static model and our main animatable model. We also reduce the maximum number of channels in each layer to 256 for our static model, further reducing the computational cost. For the static model, we further reduce the number of channels produced by the Gaussian output heads by decreasing the number of spherical harmonic coefficients. The output Gaussian attributes are still generated at the original spatial resolution to ensure the image resolution and Gaussian count remain unchanged. Maintaining the UV map dimensions allows these reductions to be evaluated independently of the number of generated Gaussian primitives.

Finally, in our static model, we train the last four synthesis blocks in FP16 [34] precision instead of FP32. Besides the reduction in memory requirements, these design changes also improve generation quality at a fixed parameter budget, as demonstrated in the ablation study in Section 4.2.

## 3.4. Loss Function

We use the non-saturating GAN loss [14]:

$$
L _ { \mathrm { a d v } } = \mathrm { s o f t p l u s } ( - D ( R ( G ) , p , \psi ) )\tag{9}
$$

where D and G are the discriminator and generator respectively, R is the renderer, p is the camera pose and ψ is the FLAME expression code. The generator loss is:

$$
L _ { G } = L _ { \mathrm { a d v } } + \lambda _ { p } L _ { \mathrm { p o s } } + \lambda _ { s } L _ { \mathrm { s c a l e } }\tag{10}
$$

where the position and scale regularisation terms are defined as:

$$
L _ { \mathrm { p o s } } = \left\| M _ { \mathrm { p o s } } \right\| _ { 2 } , \quad L _ { \mathrm { s c a l e } } = \left\| M _ { \mathrm { s c a l e } } \right\| _ { 2 }\tag{11}
$$

and $M _ { \mathrm { p o s } }$ and $M _ { \mathrm { s c a l e } }$ are the predicted position offset and predicted scale, respectively.

## 4. Results and Evaluation

Dataset: We use the FFHQ dataset [20] for training and evaluation. The dataset consists of 70k high-quality images of human faces with a wide variety of pose, expression, and lighting conditions. MODNet [22] is used to remove the background and isolate the head region for training our model.

Evaluation Metrics and Baselines: We use FID, FLOPs, inference latency and file size as our primary evaluation metrics. FID [17] is used to measure the visual quality of the generated head avatars, while FLOPs and inference latency measure the computational cost of our model at runtime. File size measures the storage and transfer requirements of the model, which are important for deployment on resourceconstrained devices.

For our main results in Table 1, we use 50K real and generated samples for FID calculation. For the ablation studies in Table 3 and Table 2, we calculate FID using 10K generated samples and 10K real samples from FFHQ. We also report $\mathrm { F I D } _ { 3 \mathrm { D } }$ [4] with 10K images, which measures generation quality under large deviations from the conditioning view. The heads are conditioned on a frontal view while the rendering viewpoints are randomly sampled from the dataset, exposing view-conditioning bias and geometric inconsistency.

We measure $\mathrm { P S N R } _ { \mathrm { M V } }$ and $\mathrm { S S I M _ { M V } }$ following the protocol of [51] and GGHead [24], generating 30 multi-view images of 100 random heads, and reconstructing the surface using [50]. These multi-view metrics measure agreement between renderings of the same identity across viewpoints. We compare our proposed approach against AGORA [13], which adds an expression deformation branch to the same synthesis backbone. Our static generator is compared against [24] which is the baseline adopted by various methods in this subdomain like [13, 52].

Implementation Details: The proposed generator block is used throughout the model. The block used to predict the Gaussian attributes is a modified version of our proposed generator block with noise disabled. We train our model on 8 NVIDIA H200 GPUs. We use the Adam optimizer with learning rates of 0.0025 and 0.002 for the generator and discriminator, respectively, and a batch size of 32. We set $\lambda _ { p } = 0 . 1$ and $\lambda _ { s } = 0 . 0 5$ , apply R1 gradient regularisation to the discriminator with a weight of 1, and use minibatch standard deviation regularisation in the discriminator. We train our model to produce UV maps at $2 5 6 ^ { 2 }$ resolution and cap the number of Gaussians at 65K. Not all Gaussians are active for each avatar as their contribution is controlled by the predicted opacity.

We train the first stage of our model for 6.5M images and then on an additional 15M images overall in the second stage. For the ablation runs reported in Table 3, we train for 5M images. The model is trained in PyTorch and the final checkpoint is exported to ONNX for inference. We calculate FID on the PyTorch checkpoints for all experiments. Figure 4 shows that both ONNX and PyTorch outputs are similar when using the same renderer.

For computational-cost evaluation, we use onnx-tool [46] to parse and profile the exported ONNX models. CPU inference latency is measured using ONNX Runtime capped to 4 cores on an AMD EPYC 9535 CPU. Mobile results are obtained using ONNX Runtime Web out of the box with a Pixel 10 smartphone. Further details on the cost evaluation and the full measurement protocol are provided in the supplementary material.

For our main model, we train an additional deformation branch similar to [13] and use our proposed synthesis blocks in both the synthesis and deformation branches. Unless otherwise stated, images are rasterised at 256<sup>2</sup>. For the fullresolution comparison in Table 1, we rasterise the same predicted Gaussians at $5 1 2 ^ { 2 }$ ; the UV attribute map, deformation plane, Gaussian count, and generator architecture remain unchanged at 256<sup>2</sup>. We report runtime separately for initial Gaussian generation and subsequent expression-conditioned animation in Table 1 to distinguish the contribution of the synthesis and deformation stages. We use the MLP proposed by [13] to speed up animation with new expressions. More details are provided in the supplementary material.

## 4.1. Quantitative Comparison

Our proposed method achieves a 70% reduction in parameter count and a 94% reduction in FLOPs compared to the baseline model, as shown in Table 1. The storage size for our model also decreases by 81%, as shown in Table 1, making it easier to store, transfer, and deploy on edge devices. The reported file sizes use the uncompressed, unquantised model weights, leaving further potential reductions through compression and quantisation. In preliminary experiments, we found that some parameters are more sensitive to quantisation than others. We therefore leave quality-aware quantisation for future work. Further details are provided in the supplementary material. Our model maintains competitive FID while substantially reducing the computational and storage requirements of the generator.

![](images/e38b2e0ba7c45a800df977ce3bf11a92ff4fa0c3b21ef25602125b36f35dff3b.jpg)

![](images/f16d3684863c880b91c6a7b753df461dd385289393a664a4ef0d6d404e64f263.jpg)

![](images/df4647723235aefef37173a131eca18f010bf5a3c0ecbf721ca440abbc7065b1.jpg)  
Figure 4. A pixel level comparison of our proposed model’s inference in PyTorch against an onnx-runtime implementation. Please note the pixel differences are enhanced by 10× for better visibility.

At $5 1 2 ^ { 2 }$ rasterisation resolution, our model obtains an FID of 4.15 compared with 3.17 for AGORA. These values are computed against $5 1 2 ^ { 2 }$ reference statistics. Because the generator still predicts a $2 5 6 ^ { 2 }$ UV attribute map and the $5 1 2 ^ { 2 }$ setting changes only rasterisation, the FLOPs, parameter count, training time, exported model size, and generator and animation latencies in Table 1 are unchanged. Appendix Section B provides the full architecture and cost breakdown. Synthesis Latency: Our model reduces CPU inference latency by 54% compared with the baseline, making it more suitable for deployment on edge devices. However, the reduction in latency is smaller than the reduction in FLOPs. We attribute this in part to ONNX Runtime execution of modulated convolution and upsampling operations as combinations of standard operators, together with the overhead of the additional upsampling operations used to maintain the UV map resolution. Custom ONNX operators and further runtime optimisation could therefore provide additional latency reductions. Our model runs the entire unconditional face synthesis pipeline, including the MLP mapping network, in 148 ms on a CPU. This can be combined with a lightweight 3DGS renderer to support complete avatar generation and rendering on edge devices. For our phone evaluation we render the Gaussians on device, but this uses a different renderer with a reduced feature set than what the model was trained with. Table 1 also reports browser-based mobile inference on a Google Pixel 10, using ONNX Runtime Web without GPU acceleration or runtime-specific optimisation. These results demonstrate that the proposed generator can execute on CPU and mobile hardware without requiring dedicated GPU acceleration.

Multi-view Consistency: Table 2 reports multi-view consistency and resource requirements for our static generator. Our method reduces peak GPU memory by 26%, from 21.7 GB to 16.0 GB, under identical testing conditions. The proposed model also improves $\mathrm { P S N R _ { M V } }$ from 32.60 to 34.01 and $\mathrm { S S I M _ { M V } }$ from 0.868 to 0.880, indicating improved agreement between renderings of the same identity across viewpoints. However, $\mathrm { F I D } _ { \mathrm { 3 D } }$ increases from 11.57 to 16.40. This discrepancy suggests that the metrics capture different aspects of multi-view generation.It can possibly point to some over smoothing happening in our method resulting in this dichotomy. The experiment indicates an increase in training time but it only runs for 5M images and our full run on the larger model shown in Table 1. reduces overall training time by 42%.

Table 1. Comparison of generation quality at $5 1 2 ^ { 2 }$ rasterisation resolution, together with computational cost, generation latency, and animation latency at 25M training images. FID is computed against $5 1 2 ^ { 2 }$ reference statistics. The generator backbone, $2 5 6 ^ { 2 }$ UV attribute map, deformation plane, and Gaussian count are unchanged; consequently, the remaining generator and deployment measurements are the same as for $2 5 6 ^ { 2 }$ rasterisation.
<table><tr><td rowspan="2">Method</td><td colspan="5">Generation Quality and Compute Cost</td><td colspan="2">Generation</td><td>Animation</td></tr><tr><td>FID↓</td><td> $\mathrm { F L O P \left( G \right) \downarrow }$ </td><td>Params  $( \mathbf { M } ) \downarrow$ </td><td>Train↓ (hrs)</td><td>Size↓ (MB)</td><td> $\mathrm { C P U \downarrow }$  (ms)</td><td>Pixel 10↓ (ms)</td><td>Pixel 10↓ (ms)</td></tr><tr><td>AGORA  $( 5 1 2 ^ { 2 } )$  [13]</td><td>3.17</td><td>212</td><td>33</td><td>50</td><td>241</td><td>323</td><td>2381</td><td>32</td></tr><tr><td>Ours  $( 5 1 2 ^ { 2 } )$ </td><td>4.15</td><td>13</td><td>10</td><td>29</td><td>46</td><td>148</td><td>453</td><td>32</td></tr></table>

![](images/89cd3435c6e8970805ecdc6d57fda03e72735b2e8a76ea09fd8dd732f50aea76.jpg)  
Figure 5. Our animation model can drive avatar expression based on FLAME parameters. In each row the expression is interpolated from the outermost images.

Table 2. We show 3D consistency, multi-view quality and efficiency metrics for our method on a smaller static model at 5M images and $2 5 6 ^ { 2 }$ resolution.
<table><tr><td>Method</td><td>FLOPs FID</td><td></td><td> $\mathrm { F I D } _ { 3 \mathrm { D } \downarrow }$ </td><td> $\mathrm { P S N R } _ { \mathrm { M V } } \uparrow$ </td><td> $\mathrm { S S I M _ { M V } \uparrow }$ </td><td>Train Time↓ VRAM↓</td><td></td></tr><tr><td>GGHEAD</td><td>66 G</td><td>9.6</td><td>11.57</td><td>32.60</td><td>0.868</td><td>10.51 hrs.</td><td>21.7 GB</td></tr><tr><td>Ours-Static</td><td>2.7 G</td><td>12.0</td><td>16.40</td><td>34.01</td><td>0.880</td><td>11.59 hrs.</td><td>16.0 GB</td></tr></table>

## 4.2. Ablations

Table 3 isolates the contribution of the architectural and efficiency modifications introduced in Section 3. Replacing the standard synthesis convolutions with our depth-wise separable blocks preserves the baseline FID of 9.6 while reducing the parameter count from 28M to 8M. Replacing the Gaussian output convolutions produces only a small increase in FID to 9.8, demonstrating that the proposed separable architecture can substantially reduce model capacity without significantly degrading generation quality. We next evaluate whether similar efficiency gains can be obtained through direct capacity reduction. Reducing the feature resolution decreases CPU latency from 354 ms to 153 ms, while further reducing the channel width reaches 137 ms and 4M parameters. However, FID increases substantially to 17.2 and 17.6, respectively, showing that naive downscaling alone produces an unfavourable quality-efficiency trade-off. Finally, we evaluate spherical harmonic reduction, feature resolution and mixed-precision training from the C1 configuration. Reducing the channel width and spherical harmonic degree to $\mathrm { { S H _ { 0 } } }$ achieves an FID of 11.1 with 4M parameters and 197 ms latency. Further reducing the feature resolution lowers the computational cost to 2.7G FLOPs and latency to 148 ms, although FID increases to 15.8. Training the final four synthesis blocks in FP16 recovers generation quality to an FID of 12.8 at the same 2.7G FLOPs, with a small increase in latency to 158 ms. Together, these results show that the efficiency gains of the final architecture do not arise from capacity reduction alone. The proposed separable blocks preserve generation quality under substantial parameter reduction, while the additional architectural and precision choices provide complementary trade-offs between quality, model size and inference latency.

![](images/cba9aa8b16cdaad3151bc81d2ff00e05920257e044db2856deabb66ae3c181fa.jpg)  
Figure 6. Interpolation between random latent codes generated by our static model at $2 5 6 ^ { 2 }$ resolution. Smooth transitions between identities indicate that meaningful latent interpolation is preserved by the efficient architecture.

## 4.3. Qualitative Results

Figure 6 shows interpolations between random latent codes generated by our proposed model at $2 5 6 ^ { 2 }$ resolution. The resulting sequences exhibit smooth transitions between identities without abrupt visual discontinuities, indicating that the efficiency modifications preserve meaningful interpolation within the learned latent space. This is particularly important for our architecture because retaining style-based modulation enables continuous control of the generated Gaussian attributes despite the use of depth-wise separable convolutions. Additional qualitative comparisons with the baseline and further generated examples are provided in the supplementary material. Figure 1 also shows our method learns meaningful degrees of variation. We provide further analysis in the supplementary material.

Animation Results: We additionally apply our proposed synthesis blocks to an animatable generator to demonstrate their applicability beyond static head synthesis. Figure 5 shows our animation model can produce expressionconditioned deformations from FLAME parameters, including independent eye and jaw motion. Further results are provided in the supplementary material, including animation

Table 3. Ablations shown at 5M images and $2 5 6 ^ { 2 }$ resolution. (a) shows that depth-wise convolutions are capable of modelling the data distribution and do not lose significant quality. Dashes mark configurations we did not profile.
<table><tr><td>Configuration</td><td>FID↓</td><td>Params↓ (M)</td><td>FLOP↓ (G)</td><td>CPU↓ (ms)</td></tr><tr><td colspan="5">(a) Depth-wise separable convolutions</td></tr><tr><td>GGHead [24]</td><td>9.6</td><td>28.0</td><td></td><td></td></tr><tr><td>+ separable synthesis convs</td><td>9.6</td><td>8.0</td><td>一</td><td></td></tr><tr><td>+ separable output convs (C1)</td><td>9.8</td><td>8.0</td><td>一</td><td>354</td></tr><tr><td colspan="5">(b) Channel reduction applied to C1</td></tr><tr><td>+ feature resolution/ 4</td><td>17.2</td><td>8.0</td><td></td><td>153</td></tr><tr><td>+ channel width (C2)</td><td>17.6</td><td>4.0</td><td></td><td>137</td></tr><tr><td colspan="5">(c) Spherical harmonics and mixed precision, from C1</td></tr><tr><td>+ channel width + SH0</td><td>11.1</td><td>4.0</td><td>7.9</td><td>197</td></tr><tr><td>+ feature resolution/ 2</td><td>15.8</td><td>4.0</td><td>2.7</td><td>148</td></tr><tr><td>+ FP16 (last 4 blocks)</td><td>12.8</td><td>4.0</td><td>2.7</td><td>158</td></tr></table>

driven by FLAME parameters estimated from monocular video.

## 5. Conclusion

Summary: We introduce an efficient generator architecture that substantially reduces the computational requirements of 3D Gaussian head synthesis while retaining competitive generation quality. Our approach reduces parameter count by 70% and computational cost by 94% compared with the baseline, while reducing model size by up to 81%. Crucially, these gains enable the complete synthesis of new 3D Gaussian head avatars on CPUs and mobile devices through a web browser, without requiring dedicated GPU acceleration or application-specific software. Beyond efficient rendering or re-animation of existing avatars, our approach makes the generation of new identities practical on resource-constrained hardware, addressing a key bottleneck in existing 3D Gaussian avatar pipelines. The proposed architecture therefore provides a practical foundation for deployable generative 3D avatar systems, enabling interactive synthesis and personalisation across edge, mobile and web-based applications.

Limitations: The reduction in inference latency is smaller than the corresponding reduction in computational cost, indicating that practical performance remains constrained by the available runtime operations and their implementation. We also observe a discrepancy between the improved $\mathrm { P S N R } _ { \mathrm { M V } }$ and $\mathrm { S S I M _ { M V } }$ metrics and the degradation in $\mathrm { F I D } _ { 3 \mathrm { D } } .$ , which requires further investigation. Reducing the spherical harmonic representation also limits the ability of the most efficient model to represent view-dependent appearance. The tested implementation did not make use of WebGPU [48], which could provide hardware-accelerated browser execution. Future work will investigate sensitivity-aware quantisation and optimised operators for convolution and modulation to further reduce model size and inference latency.

Ethical Considerations: The FFHQ dataset used to train our models contains demographic biases that may be reflected in the distribution and quality of the generated avatars. Reducing the computational requirements for generating realistic head avatars also lowers the barrier to their creation and therefore introduces dual-use risks, including their potential use for misinformation and deepfakes. We therefore encourage the development and adoption of appropriate safeguards alongside continued research into efficient generative avatar technology.

## References

[1] Rameen Abdal, Wang Yifan, Zifan Shi, Yinghao Xu, Ryan Po, Zhengfei Kuang, Qifeng Chen, Dit-Yan Yeung, and Gordon Wetzstein. Gaussian shell maps for efficient 3D human generation. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2024. 2

[2] Sizhe An, Hongyi Xu, Yichun Shi, Guoxian Song, Umit Y. Ogras, and Linjie Luo. Geometry-aware 3D full-head synthesis in 360<sup>◦</sup>. In CVPR, 2023. 2

[3] Milena T. Bagdasarian, Paul Knoll, Yi-Hsin Li, Florian Barthel, Anna Hilsmann, Peter Eisert, and Wieland Morgenstern. 3DGS.zip: A survey on 3D Gaussian splatting compression methods. Computer Graphics Forum, 2025. 3

[4] Florian Barthel, Wieland Morgenstern, Paul Hinzer, Anna Hilsmann, and Peter Eisert. Cgs-gan: 3d consistent gaussian splatting gans for high resolution human head synthesis. Advances in Neural Information Processing Systems, 38: 89230–89258, 2026. 1, 2, 3, 5

[5] Sergei Belousov. MobileStyleGAN: A lightweight convolutional neural network for high-fidelity image synthesis, 2021. 2, 12

[6] Eric R. Chan, Connor Z. Lin, Matthew A. Chan, Koki Nagano, Boxiao Pan, Shalini De Mello, Orazio Gallo, Leonidas Guibas, Jonathan Tremblay, Sameh Khamis, Tero Karras, and Gordon Wetzstein. Efficient geometry-aware 3D generative adversarial networks. In CVPR, 2022. 1, 2

[7] Jierun Chen, Dongting Hu, Xijie Huang, Huseyin Coskun, Arpit Sahni, Aarush Gupta, Anujraaj Goyal, Dishani Lahiri, Rajesh Singh, Yerlan Idelbayev, et al. Snapgen: Taming high-resolution text-to-image models for mobile devices with efficient architectures and training. In 2025 IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pages 7997–8008. IEEE, 2025. 3

[8] Xingyu Chen, Yu Deng, and Baoyuan Wang. Mimic3D: Thriving 3d-aware GANs via 3d-to-2d imitation. In ICCV, 2023. 2

[9] Zhiqin Chen, Thomas Funkhouser, Peter Hedman, and Andrea Tagliasacchi. MobileNeRF: Exploiting the polygon rasterization pipeline for efficient neural field rendering on mobile architectures. In Proceedings ofthe IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2023. 3

[10] Aviral Chharia and Fernando De la Torre. Multi-view consistent 3d gaussian head avatars’ without’multi-view generation. arXiv preprint arXiv:2605.25220, 2026. 2

[11] Yu Deng, Jiaolong Yang, Jianfeng Xiang, and Xin Tong. GRAM: Generative radiance manifolds for 3d-aware image generation. In CVPR, 2022. 1, 2

[12] Zhiwen Fan, Kevin Wang, Kairun Wen, Zehao Zhu, Dejia Xu, and Zhangyang Wang. Lightgaussian: Unbounded 3d gaussian compression with 15x reduction and 200+ fps, 2024. 3

[13] Ramazan Fazylov, Sergey Zagoruyko, Aleksandr Parkin, Stamatis Lefkimmiatis, and Ivan Laptev. AGORA: Adversarial generation of real-time animatable 3D gaussian head avatars. arXiv preprint arXiv:2512.06438, 2025. 1, 2, 3, 5, 6, 7, 11, 12

[14] Ian J. Goodfellow, Jean Pouget-Abadie, Mehdi Mirza, Bing Xu, David Warde-Farley, Sherjil Ozair, Aaron Courville, and Yoshua Bengio. Generative adversarial nets. In NeurIPS, pages 2672–2680. MIT Press, 2014. 1, 2, 5

[15] Seonghee Han, Minchang Chung, Gyeongsu Cho, Kyungdon Joo, and Taehwan Kim. Avatar++: Fast and pose-controllable 3D human avatar generation from a single image. In ICCV Workshop on Wild 3D, 2025. 2

[16] Xiao Han, Yukang Cao, Kai Han, Xiatian Zhu, Jiankang Deng, Yi-Zhe Song, Tao Xiang, and Kwan-Yee K. Wong. HeadSculpt: Crafting 3D head avatars with text. In NeurIPS, 2023. 2

[17] Martin Heusel, Hubert Ramsauer, Thomas Unterthiner, Bernhard Nessler, and Sepp Hochreiter. GANs trained by a two time-scale update rule converge to a local nash equilibrium. NeurIPS, 30, 2017. 5

[18] Sangeek Hyun and Jae-Pil Heo. GSGAN: Adversarial learning for hierarchical generative 3D gaussian splatting. In Advances in Neural Information Processing Systems (NeurIPS), 2024. 2

[19] Haolin Jia, Qifei Wang, Omer Tov, Yang Zhao, Fei Deng, Lu Wang, Chuo-Ling Chang, Tingbo Hou, and Matthias Grundmann. BlazeStyleGAN: A real-time on-device StyleGAN. In CVPR Workshops, pages 4690–4694, 2023. 2, 12

[20] Tero Karras, Samuli Laine, and Timo Aila. A style-based generator architecture for generative adversarial networks. In CVPR, 2019. 1, 5

[21] Tero Karras, Samuli Laine, Miika Aittala, Janne Hellsten, Jaakko Lehtinen, and Timo Aila. Analyzing and improving the image quality of StyleGAN. In CVPR, 2020. 2, 3, 5

[22] Zhanghan Ke, Jiayu Sun, Kaican Li, Qiong Yan, and Rynson W. H. Lau. MODNet: Real-time trimap-free portrait matting via objective decomposition. In AAAI, 2022. 5

[23] Bernhard Kerbl, Georgios Kopanas, Thomas Leimkuhler, and¨ George Drettakis. 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics, 42(4), 2023. 1, 2, 3

[24] Tobias Kirschstein, Simon Giebenhain, Jiapeng Tang, Markos Georgopoulos, and Matthias Nießner. Gghead: Fast and generalizable 3d gaussian heads. arXiv preprint arXiv:2406.09377, 2024. 1, 2, 3, 5, 8

[25] Tobias Kirschstein, Simon Giebenhain, and Matthias Nießner. 3DGH: 3D head generation with composable hair and face. ACM Transactions on Graphics (SIGGRAPH), 2025. 2

[26] Guohao Li, Hongyu Yang, Yifang Men, Di Huang, Weixin Li, Ruijie Yang, and Yunhong Wang. Generating editable head avatars with 3D gaussian GANs. In ICASSP, 2025. 2

[27] Heyuan Li, Ce Chen, Tianhao Shi, Yuda Qiu, Sizhe An, Guanying Chen, and Xiaoguang Han. Spherehead: stable 3d full-head synthesis with spherical tri-plane representation. In European Conference on Computer Vision, pages 324–341. Springer, 2024. 2

[28] Muyang Li, Ji Lin, Yaoyao Ding, Zhijian Liu, Jun-Yan Zhu, and Song Han. GAN Compression: Efficient architectures for interactive conditional GANs. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2020. 2

[29] Tianye Li, Timo Bolkart, Michael J. Black, Hao Li, and Javier Romero. Learning a model of facial shape and expression from 4D scans. ACM Transactions on Graphics, (Proc. SIG-GRAPH Asia), 36(6):194:1–194:17, 2017. 2, 3

[30] Yanyu Li, Huan Wang, Qing Jin, Ju Hu, Pavlo Chemerys, Yun Fu, Yanzhi Wang, Sergey Tulyakov, and Jian Ren. SnapFusion: Text-to-image diffusion model on mobile devices within two seconds. In Advances in Neural Information Processing Systems (NeurIPS), 2023. 3

[31] Ji Lin, Richard Zhang, Frieder Ganz, Song Han, and Jun-Yan Zhu. Anycost GANs for interactive image synthesis and editing. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2021. 2

[32] Yuchen Liu, Zhixin Shu, Yijun Li, Zhe Lin, Federico Perazzi, and S. Y. Kung. Content-aware GAN compression. In Proceedings ofthe IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2021. 2

[33] Shengjie Ma, Yanlin Weng, Tianjia Shao, and Kun Zhou. 3d gaussian blendshapes for head avatar animation. In ACM SIGGRAPH 2024 Conference Papers, pages 1–10, 2024. 2

[34] Paulius Micikevicius, Sharan Narang, Jonah Alben, Gregory Diamos, Erich Elsen, David Garcia, Boris Ginsburg, Michael Houston, Oleksii Kuchaiev, Ganesh Venkatesh, and Hao Wu. Mixed precision training. In ICLR, 2018. 5

[35] Microsoft. ONNX runtime: Cross-platform, high performance ml inferencing and training accelerator, 2021. 12, 13

[36] Ben Mildenhall, Pratul P. Srinivasan, Matthew Tancik, Jonathan T. Barron, Ravi Ramamoorthi, and Ren Ng. Nerf: Representing scenes as neural radiance fields for view synthesis. In ECCV, 2020. 1, 2

[37] Wieland Morgenstern, Florian Barthel, Anna Hilsmann, and Peter Eisert. Compact 3d scene representation via selforganizing gaussian grids. In European Conference on Computer Vision, pages 18–34. Springer, 2024. 3

[38] Simon Niedermayr, Josef Stumpfegger, and Rudiger West-¨ ermann. Compressed 3D Gaussian splatting for accelerated novel view synthesis. In Proceedings ofthe IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2024. 3

[39] Ben Poole, Ajay Jain, Jonathan T. Barron, and Ben Mildenhall. DreamFusion: Text-to-3d using 2d diffusion. arXiv, 2022. 2

[40] Shenhan Qian, Tobias Kirschstein, Liam Schoneveld, Davide Davoli, Simon Giebenhain, and Matthias Nießner. GaussianAvatars: Photorealistic head avatars with rigged 3D gaussians.

In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2024. 2

[41] Tim Salimans and Diederik P. Kingma. Weight normalization: A simple reparameterization to accelerate training of deep neural networks. In NeurIPS, 2016. 5

[42] Katja Schwarz, Axel Sauer, Michael Niemeyer, Yiyi Liao, and Andreas Geiger. VoxGRAF: Fast 3d-aware image synthesis with sparse voxel grids. In NeurIPS, 2022. 1, 2

[43] Jingxiang Sun, Xuan Wang, Lizhen Wang, Xiaoyu Li, Yong Zhang, Hongwei Zhang, and Yebin Liu. Next3D: Generative neural texture rasterization for 3D-aware head avatars. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2023. 2

[44] Jiapeng Tang, Davide Davoli, Tobias Kirschstein, Liam Schoneveld, and Matthias Nießner. GAF: Gaussian avatar reconstruction from monocular videos via multi-view diffusion. arXiv, 2024. 2

[45] Felix Taubner, Ruihang Zhang, Mathieu Tuli, and David B. Lindell. CAP4D: Creating animatable 4D portrait avatars with morphable multi-view diffusion models. In CVPR, 2025. 2

[46] ThanatosShinji. onnx-tool: A tool for parsing, editing, optimizing, and profiling ONNX models, 2023. 6, 11

[47] Dmitry Ulyanov, Andrea Vedaldi, and Victor Lempitsky. Instance normalization: The missing ingredient for fast stylization. arXiv preprint arXiv:1607.08022, 2016. 5

[48] W3C GPU for the Web Working Group. WebGPU, 2025. 8

[49] Qipeng Wang, Shiqi Jiang, Zhenpeng Chen, Xu Cao, Yuanchun Li, Aoyu Li, Yun Ma, Ting Cao, and Xuanzhe Liu. Anatomizing deep learning inference in web browsers. ACM Transactions on Software Engineering and Methodology, 34 (2):1–43, 2025. 3

[50] Yiming Wang, Qin Han, Marc Habermann, Kostas Daniilidis, Christian Theobalt, and Lingjie Liu. NeuS2: Fast learning of neural implicit surfaces for multi-view reconstruction. In ICCV, 2023. 5

[51] Jianfeng Xiang, Jiaolong Yang, Yu Deng, and Xin Tong. GRAM-HD: 3d-consistent image generation at high resolution with generative radiance manifolds. In ICCV, 2023. 2, 5

[52] Zhengming Yu, Tianye Li, Jingxiang Sun, Omer Shapira, Seonwook Park, Michael Stengel, Matthew Chan, Xin Li, Wenping Wang, Koki Nagano, and Shalini De Mello. GAIA: Generative animatable interactive avatars with expressionconditioned gaussians. In ACM SIGGRAPH, 2025. 1, 2, 3, 5

## A. Implementation and Evaluation Details

## A.1. Training and Measurement Protocol

The results for the CPU inference time are obtained by using the onnx-runtime in a Python environment with an AMD EPYC 9535 CPU, with the runtime restricted to four threads and four CPU cores for all reported results, including Table 1 of the main paper. We report the best run over repeated measurements after a warm-up pass. For the edge device evaluation we leave the inter- and intra-process thread counts up to the runtime environment and manually restrict them on the desktop CPU. The device is kept out of the power saving mode and background processes are minimized to ensure the best possible performance. Note that on the edge device the model runs without any GPU acceleration. The reported model sizes are the file sizes on disk, without any additional compression applied, which leaves open the scope for further space savings and faster network transfer. All FID and $\mathrm { F I D } _ { 3 \mathrm { D } }$ numbers are computed on the PyTorch checkpoints rather than on the exported ONNX checkpoints, since the export is used only for the efficiency measurements; Section E shows that the two produce near-identical outputs, so the quality numbers transfer to the exported model.

## A.2. Computational Cost Evaluation

The edge device cost is measured with the onnx-runtime on a Pixel 10 mobile phone. Both the full generation pipeline and the animation MLP are run and benchmarked individually. The model is served inside a simple web page and the inference and the evaluation are performed entirely on the mobile device. All dependencies are also sent over the network, so we additionally report the overall transfer size. Transferring the full model, comprising the weight files, the SVD basis of the animation network, the onnx runtime and the FLAME data, amounts to 75.59 MiB across 24 files in total, which is quick to transfer to a mobile device over a stable internet connection, and restarting the application is considerably faster once these files are cached. For FLOP calculation we report the Forward MACs reported by onnxtool [46], where one MAC is defined as 1 M $\mathrm { A C } = \mathrm { f l o a t } ( \mathrm { a } ) \ ^ { * }$ float(b) + float(c). The reported parameter and FLOP counts cover the exported generator only, and therefore exclude the discriminator, which is not used at inference time, and the Gaussian rasteriser, which is not part of the exported graph.

## B. Architecture for Full Resolution

Table 1 reports FID at $5 1 2 ^ { 2 }$ rasterisation resolution while retaining the generator and deployment measurements of the corresponding $2 5 6 ^ { 2 }$ setting. Here we provide the complete architecture and cost breakdown that explains why those measurements are unchanged. It is important to note that this is the same network as the $2 5 6 ^ { 2 }$ model: the UV attribute backbone still ends at a $2 5 6 ^ { 2 }$ UV map and the deformation plane resolution is likewise still $2 5 6 ^ { 2 }$ . Moving to a $5 1 2 ^ { 2 }$ output changes the resolution at which the Gaussians are rasterised, not the network that produces them. Consequently the structural cost of the generator is unchanged, and the parameter count, the FLOP count and the exported file size at $5 1 2 ^ { 2 }$ are identical to the values measured for the $2 5 6 ^ { 2 }$ model. The exported generator graph is also identical; differences between latency figures reported from separate profiling runs reflect measurement conditions rather than a change in the network. The additional cost of rendering at $5 1 2 ^ { 2 }$ therefore lies entirely in the Gaussian rasteriser, which remains a native CUDA implementation outside the exported graph, and the numbers in Table 4 should not be read as the cost of producing a $5 1 2 ^ { 2 }$ output.

Table 4. Cost breakdown of the generator used for $5 1 2 ^ { 2 }$ rendering. The branches are profiled individually while the full model is timed as a single end-to-end run of the complete pipeline, so the branch latencies do not add up directly to the full-model latency. All reported times are medians on a single CPU core; the full model takes 171.3 ms when four threads are used. Parameter, FLOP and size figures are identical to those of the $2 5 6 ^ { 2 }$ model, since the UV attribute backbone and the deformation plane both remain at $2 5 6 ^ { 2 }$ and only the rasterisation resolution changes.
<table><tr><td>Component</td><td>Params (M)</td><td>GFLOP</td><td>Size (MB)</td><td>Time (ms)</td></tr><tr><td>Synthesis</td><td>7.74</td><td>7.42</td><td>31.51</td><td>134.8</td></tr><tr><td>Deformation</td><td>2.13</td><td>5.32</td><td>14.63</td><td>129.4</td></tr><tr><td>Full</td><td>10.67</td><td>12.74</td><td>46.12</td><td>246.8</td></tr></table>

Table 4 reports the breakdown for this model. The full generator contains 10,673,119 parameters, requires 12.735 GFLOP, equivalently 6.367 GMAC, per forward pass and exports to an onnx graph of 46.116 MB. On the desktop CPU described in Section A.1 the median latency of the full pipeline is 246.8 ms on a single core, and 171.3 ms when four threads are used. The synthesis and deformation branches are also profiled individually, and the deformation branch accounts for roughly a fifth of the parameters while contributing a substantially larger share of the FLOPs, since it operates on the full deformation plane. We verify the export at this configuration as in Section E, and the maximum relative deviation between the PyTorch and onnx outputs is $2 . 9 9 \times 1 0 ^ { - 6 }$ , well inside our acceptance threshold of $1 0 ^ { - 4 }$

Table 5 reports the corresponding generation quality at $2 5 6 ^ { 2 }$ resolution, complementing the $5 1 2 ^ { 2 }$ results in Table 1 of the main paper. Our model reaches an FID of 4.3 against 3.8 for AGORA [13]. The gap in quality is modest given that our generator is the same network used for $5 1 2 ^ { 2 }$ rasterisation, and it is obtained at the substantially reduced parameter, FLOP and storage budget reported in Table 4.

Table 5. Generation quality at $2 5 6 ^ { 2 }$ resolution. FID is computed on the PyTorch checkpoints against reference statistics at the matching resolution, following the protocol of Section A.1.
<table><tr><td>Method</td><td>FID ↓</td></tr><tr><td>AGORA [13]</td><td>3.8</td></tr><tr><td>Ours</td><td>4.3</td></tr></table>

## C. Architecture Details

## C.1. Depth-wise Separable Convolutions

We replace all the convolutions in the synthesis layer with depthwise convolutions for the first experiment in Table 3(a) of the main paper but use normal convolutions in the UV channel synthesis layer. For the second experiment we replace all the convolutions in the synthesis layer and the UV channel synthesis layer with depthwise convolutions. There is a significant reduction in the parameter count however there is minimal change in the FID score of the models.

## C.2. Spherical Harmonics, Channel Width and Precision

For the spherical harmonics ablation we start with the DW-Base configuration, halve the number of channels and reduce the spherical harmonics degree to 0. In the second experiment we also halve the channel height and width on top of the previous changes, and in the final experiment we also train the last 4 synthesis blocks in FP16 precision instead of the normal FP32 precision. Halving the channel width and height makes the model faster than the baseline by 36% but it suffers in terms of quality as indicated by the FID score, and we hypothesize that the reduced capacity in the model forces a loss in terms of the data distribution modelling capability. Using FP16 precision for the last 4 synthesis blocks potentially allows the model to store and analyze more combinations of features in the earlier layers with smaller spatial dimensions. For the later layers with higher spatial dimensions the solution space is smaller and the combinations can be spread more spatially. The inference time however increases slightly, which could be due to the runtime cost of converting FP16 tensors to FP32 for the operations which are not supported in FP16 precision. We also convert the UV maps back to FP32 before rendering them and this could be contributing to additional load.

## C.3. Generator and Feature Map Sizes

Each synthesis block includes two of the modulated convolution blocks of Figure 3 together with a Gaussian output layer whose outputs are accumulated into the final UV map. We use different size feature maps inside individual synthesis blocks to further reduce parameters and FLOPs. Additional upsampling operations are used before the Gaussian output layer to ensure a consistent UV map output resolution and therefore an unchanged number of Gaussians across all of our variants. Keeping the Gaussian count fixed ensures that the comparisons in the main paper reflect the capacity of the generator and not a change in the number of primitives being rendered.

## C.4. Generator Output Heads

We also experiment with removing the cumulative creation of the Gaussian output channels following [5] but it has an adverse impact on the quality and fidelity of the generated avatars similar to [19]. We posit it removes direct gradient propagation to earlier resolution synthesis blocks which is critical for stable training especially with Gaussian attributes which are very sensitive to minor changes. A small error in a predicted position channel displaces a primitive in 3D where it is amplified by the renderer, whereas the same error in an RGB generator only perturbs a single pixel value. We therefore retain the cumulative structure in our generator.

## D. Quantisation Sensitivity

The file sizes reported in Table 1 of the main paper are for uncompressed and unquantised FP32 weights, so they represent an upper bound on the storage cost of our model. In preliminary experiments we applied uniform post-training quantisation to the generator weights and observed that the sensitivity is highly uneven across the network. Some layers tolerate reduced precision with little change in FID, whereas the Gaussian output heads, and in particular the layers producing the position and scale channels, degrade quickly. This mirrors the behaviour discussed in Section C.4: an error in a position channel displaces a primitive in 3D and is amplified by the renderer, while the same error in a colour channel perturbs only the appearance of one primitive. A uniform quantisation of the whole generator therefore trades a substantial part of the quality for the additional size reduction, while leaving the Gaussian attribute heads in higher precision retains quality at a smaller saving. A quality-aware scheme that assigns precision per attribute group is the natural next step, and we leave it for future work rather than reporting a partial result here.

## E. ONNX Export Ablation

Figure 4 of the main paper shows the pixel level difference between the output of our model in PyTorch and the onnxruntime implementation [35]. The onnx-runtime implementation is able to closely replicate the output from the PyTorch implementation with minimal pixel differences, which are enhanced 10× in that figure for better visibility. Please note that during the conversion process some highly optimized operations like modconv are re-implemented using a combination of standard supported operations, so this check confirms that the efficiency numbers in the main paper are measured on a model equivalent to the one evaluated for quality. The residual differences are concentrated at highfrequency edges and are consistent with the accumulation of floating point differences between the fused PyTorch kernels and their decomposed ONNX equivalents.

![](images/387905e720da65a2f5596c65797bbdd0086b7f424b93e677fca153d863ae0405.jpg)  
GGHead

![](images/350ca1850082ac0297cc85b2a0ce5bd867d6579a56b2e4b7baa3c3b423411277.jpg)  
Ours

![](images/1cbddfd816bb3669f38101dfb830685c1f7fe94ae77c73e5dfa837d6d5c5500f.jpg)  
Ours  
Figure 7. Qualitative results from our proposed model and the baseline GGHead model at $2 5 6 ^ { 2 }$ resolution. Please note these are trained for 5M images as outlined in Section 4.

For the onnx-runtime [35] based evaluation we produce the UV maps from the onnx model after conversion from Py-Torch, and the rendering is then performed using the original Python and PyTorch codebase with the FLAME template mesh to ensure consistency with the quality evaluation. On the mobile phone the Gaussians are instead rasterised by a web based splat renderer, which differs from the renderer used during training and introduces minor visual artifacts that are not present in the PyTorch results.

## F. Additional Qualitative Results

Figure 7 compares samples from our proposed model against the baseline GGHead model at $2 5 6 ^ { 2 }$ resolution, with both models trained for 5M images. The identities produced by our model are of comparable visual quality despite the substantially reduced parameter count and FLOP budget, and the geometry remains stable across the sampled identities. Further generated examples are included in the supplementary video.

## G. Analysis of Learned Variation

## G.1. Latent Space Variation

Figure 1 of the main paper shows that our model learns meaningful degrees of variation, and we analyse this further here. Because we retain style-based modulation in the depth-wise separable synthesis blocks, the generator keeps an intermediate latent space in which individual directions correspond to interpretable factors of variation. Figure 8 shows the effect of traversing such directions: moving along a single direction changes one factor while leaving the remaining identity largely intact. The transitions are smooth and free of abrup discontinuities, which indicates that the reduced-capacity generator has not collapsed onto a small set of modes and that the mapping from the latent space to the Gaussian attribute maps remains locally well behaved. This matters for our setting because the manipulation is applied to the style codes and therefore costs a single additional forward pass through the generator, so identity editing remains available on an edge device without any optimisation loop at inference time. We observe that directions affecting appearance, such as colouring and illumination, are more cleanly separated than directions affecting geometry, which is consistent with the attribute sensitivity analysis in Section G.2, where the geometric attribute groups are the ones carrying the highest resolution requirement.

## G.2. Gaussian Attribute Sensitivity

The generator emits position, rotation, scale, opacity and spherical harmonic coefficients as a single map at a single resolution, an arrangement inherited from image synthesis, where the three output channels are samples of one radiometric field and a shared sampling rate is therefore appropriate. The channels of a Gaussian attribute map are unrelated physical quantities, and we do not assume that they share a resolution requirement. We estimate the requirement of each group independently by low-pass filtering that group to a reduced resolution, restoring it bilinearly to the full resolution, and leaving the remaining groups unmodified, which yields the marginal value of resolution to that group alone. All measurements are taken at inference time on frozen weights and are reported in $\mathrm { F I D } _ { 3 \mathrm { D } }$ , since the intervention acts on geometry.

The result is shown in Figure 9, and the groups behave very differently. The position channels are by far the most sensitive: reducing their resolution degrades $\mathrm { F I D } _ { 3 \mathrm { D } }$ well before any other group is affected, because a low-pass filter applied to positions moves neighbouring primitives towards a common location and directly removes geometric detail that the renderer then cannot recover. Scale and rotation follow, but with a visibly flatter response, since these attributes vary more slowly across the surface of the head and neighbouring primitives are already similar. The opacity and spherical harmonic groups are the most tolerant and can be reduced substantially before the curve departs from the unmodified model, which is the behaviour expected of quantities that are smooth over the UV map. Two observations follow. First, the common practice of emitting every attribute at a single shared resolution over-provisions the appearance channels in order to satisfy the requirement of the position channels, and this over-provisioning is paid for on every forward pass. Second, the ordering of the curves matches the quantisation behaviour reported in Section D, where the position and scale heads were also the least tolerant to a reduction in precision. Both results point at the same conclusion, that the geometric attributes carry the information budget of the representation, and that a generator which spends its resolution and its precision per attribute group rather than uniformly is the more promising direction for further efficiency gains.

![](images/570efc247a1417add91f5a5dfb4ac5a6a1b104d6c830cd169bfd85cc8beff93e.jpg)  
Figure 8. Latent space manipulation. Traversing individual directions in the intermediate latent space of our generator produces smooth, largely disentangled changes to a single factor of variation while the remaining identity is preserved, showing that the depth-wise separable synthesis blocks retain the editable style space of the baseline architecture.

![](images/8c327247a5659ac88a52971a8510f0cec1c2fe0cad6196aa645d826713513a6f.jpg)  
Figure 9. Resolution sensitivity of each attribute group. Each curve low-passes one group to the resolution on the horizontal axis and bilinearly restores it, on frozen weights, leaving the other five groups untouched; the dotted line is the unmodified model.

## H. Additional Animation Results

Figure 5 of the main paper shows that our animation model produces expression-conditioned deformations from FLAME parameters, including independent eye and jaw motion. Further animation results are included in the supplementary video, including avatars driven by FLAME parameters estimated from monocular video.