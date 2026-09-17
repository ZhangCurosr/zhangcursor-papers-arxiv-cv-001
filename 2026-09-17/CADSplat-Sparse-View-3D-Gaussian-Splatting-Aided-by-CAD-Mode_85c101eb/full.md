# CADSplat: Sparse-View 3D Gaussian Splatting Aided by CAD Models for Robust, Photorealistic Digital-Twin Reconstruction

Kristof Overdulve <sup>iD1\*</sup>, Lode Jorissen <sup>iD1</sup> and Nick Michiels <sup>iD1</sup>

<sup>1</sup>Digital Future Lab, Flanders Make, Hasselt University, Hasselt, Belgium.

\*Corresponding author(s). E-mail(s): kristof.overdulve@uhasselt.be; Contributing authors: lode.jorissen@uhasselt.be; nick.michiels@uhasselt.be;

## Abstract

We present CADSplat, a framework that reconstructs photorealistic, geometrically accurate digital twins from sparse (< 15 views), wide-baseline posed images of an object by regularizing 3D Gaussian Splatting (3DGS) with an explicit CAD shape prior. Using such a prior requires finding a CAD model whose shape resembles the object depicted in the images and determining the pose of each camera relative to the object. We obtain both by matching segmented object silhouettes against silhouettes rendered from a CAD library and keeping the camera-to-object poses of the best-matching model. We then anchor 3D Gaussian primitives to the surface of the retrieved model and jointly optimize the 3DGS parameters, the camera-to-object registration, and a non-rigid deformation field to account for shape diferences between the physical object and the CAD model. Across two real-world datasets, CADSplat outperforms unconstrained, few-shot, and mesh-texturing baselines and degrades gracefully to as few as 3 views. Our experiments show that most of the gain in rendering quality comes from how the splats are constrained—a fixed set of splats tied to a surface and moved by a single smooth deformation field—rather than from the CAD shape itself. The CAD model adds shape knowledge where views are scarcest, in the sparsest captures and on strongly self-occluded objects, and it places every camera in the object’s own frame. This enables applications beyond novel-view synthesis, such as markerless augmented reality registration, per-image object pose estimation, physical simulations, and the transfer of part labels from the design to the reconstruction.

Keywords: 3D Gaussian Splatting, Sparse-view reconstruction, Computer Aided Design, Digital twin, view synthesis, Non-rigid deformation, Silhouette matching

## 1 Introduction

3D representations of physical objects fall into two paradigms: manually designed explicit geometric models and learned 3D representations from camera imagery. Explicit representations, specifically Computer-Aided Design (CAD) models, are commonly used in manufacturing, robotics, and ecommerce. They provide rigid, semantically interpretable, and topologically clean structures that encode the theoretical ground truth of a designed object. However, such models require significant manual labor to create and often lack the textures, material properties, and subtle geometric imperfections necessary for photorealism. Conversely, diferentiable novel-view synthesis (NVS) methods such as Neural Radiance Fields (NeRF) [1] and 3D Gaussian Splatting (3DGS) [2] generate photorealistic 3D representations directly from imagery. However, this is an underdetermined problem, especially when views are sparse, causing the geometry of these learned representations to become noisy and prone to hallucinating false geometry to satisfy the training input, yet failing to generalize well to novel views.

(a)  
(b)  
![](images/22a11b6441b48d84746f354d868d527fe050b66eb29e97afad3f5b44fcb4b6b6.jpg)  
(c)  
Fig. 1 CADSplat: Our method regularizes sparse-view 3D Gaussian Splatting (3DGS) using CAD priors. (a) Given a handful of wide-baseline images with segmentation masks depicting the object silhouettes, the masks are matched against renderings of a CAD library, retrieving the most similar CAD model and registering the relative camera extrinsics to it to obtain the camera-to-object poses. (b) A joint optimization refines this registration, learns a non-rigid deformation field that corrects shape discrepancies between the imaged physical object and the matched CAD model, and 3DGS parameters to (c) recover a geometrically accurate, photorealistic 3D representation.

The dense-capture assumption underlying these novel-view synthesis algorithms limits their broad applicability. Two common data-capture regimes, in particular, violate it. First, multicamera rigs, whether deployed on factory lines or as in-vehicle sensor suites, view objects from only a small number of fixed, wide-baseline viewpoints. Such rigs are typically pre-calibrated, so the relative geometry of the cameras is approximately known. However, any physical calibration inevitably degrades over time due to mechanical vibration, accidental knocks during maintenance, and setup errors, compounding relative calibration errors. Second, in-the-wild multi-viewpoint captures, such as product listings on websites or photographs documenting insurance claims, are typically made with per-viewpoint aesthetics or damage documentation in mind, yielding sparse, wide-baseline, and incomplete coverage with no pre-calibration, so that relative poses must be recovered from the images themselves. Only recently have learned features and matchers [3, 4] made Structure-from-Motion (SfM) more viable in this regime.

Fortunately, a powerful structural prior is often available: a CAD model of a shape similar to the object depicted in the images. In industrial settings, the manufacturer almost always possesses accurate engineering models. In more general settings, large repositories such as ShapeNet [5] provide CAD models matching a broad range of real-world objects. We therefore pursue the “best of both worlds” in 3D representations: aligning sparse-view image captures with a topologically accurate CAD model to reconstruct a photorealistic, geometrically accurate digital twin.

We propose CADSplat, a method that jointly recovers 6-Degrees-of-Freedom (DoF) camera-toobject poses and a photorealistic 3DGS representation [2] of a physical object from a sparse, wide-baseline capture by using CAD priors. This problem is challenging for multiple reasons. First, we need to identify the CAD model whose shape best matches the imaged object and register the relative calibration with that CAD model’s coordinate frame. We achieve this by matching segmented object silhouettes against masked CAD library renders (section 3.2). This silhouette-based camera-to-object registration is only coarsely accurate. We therefore refine it during optimization (section 3.3). Second, the matched model rarely matches the physical object perfectly due to machining tolerances, wear, or the absence of the exact design. We bridge this gap with a learnable, non-rigid deformation field that warps the canonical CAD shape onto the physical observations (section 3.5). By jointly optimizing the camera-to-object registration, the deformation field, and the 3DGS parameters, we recover improved camera-to-object poses and a photorealistic, view-dependent appearance (section 3.6).

In addition to achieving state-of-the-art reconstruction quality, our pipeline enables multiple applications (section 5) that are not covered by standard NVS algorithms: automated markerless registration for augmented reality-guided maintenance [6], per-image object-pose estimation for robotics, and physics simulations using the deformed CAD model as a rigid body. The CAD prior also extends 3DGS reconstructions with semantics: because every splat is sampled from a face of the CAD mesh, it inherits the part it sits on, so the model’s part decomposition, labels, and metadata transfer onto the photorealistic twin without any manual annotation. Finally, the learned deformation provides an explicit, interpretable record of where the physical object deviates from its CAD design—a first step toward automated inspection.

In summary, our key contributions are:

1. A constrained formulation of 3D Gaussian Splatting for sparse views: a fixed, dense splat set anchored to the surface of a deformable shape prior in a canonical frame. It achieves state-of-the-art rendering quality from 9 to 13 views and gracefully degrades to 3 views.

2. A silhouette-based camera-to-object registration that retrieves a CAD model from a library, anchors a calibrated sparse capture to its canonical frame, and refines the registration jointly with the reconstruction.

3. A non-rigid deformation field that warps the CAD geometry onto the physical object, together with two appearance regularizers to generalize better to novel views in the sparseview regime.

## 2 Related Work

## 2.1 Sparse-View Synthesis

Novel-view synthesis has been fundamentally revolutionized by Neural Radiance Fields (NeRF) [1], which optimize continuous volumetric functions via ray marching, and by 3D Gaussian Splatting (3DGS) [2], which represents scenes as explicit 3D ellipsoids. However, these methods are notoriously data-hungry, requiring dense multi-view coverage to produce high-quality novel views.

Dense capture is often impractical. As a result, specialized sparse-view methods such as FSGS [7] and DNGaussian [8] have been developed that promise high-quality renderings from novel views using dense stereo or monocular depth priors [8, 9], semantic consistency priors [10, 11], or both [7]. Others approach the problem leveraging generative priors to repair poorly reconstructed regions [12, 13]. More recently, feed-forward networks regress Gaussian parameters directly from as few as one or two images: pixelSplat [14], and MVSplat [15] from posed image pairs, Splatter Image [16], and SHARP [17] from a single photograph. To overcome ambiguity, they pretrain a large-scale regression neural network on large multi-view corpora, leveraging learned priors for novel sparse-view scenes. As their prior is generative, regions that are unobserved or ambiguous are completed with content that is plausible under the training distribution, but not necessarily faithful to the actual object depicted in the imagery. Moreover, priors learned from everyday scenes transfer poorly to the reflective, textureless objects common in industrial applications. Geometry foundation models ofer a middle ground: InstantSplat [18] does not regress Gaussians directly but uses MASt3R to predict camera poses and a dense point cloud from a few unposed images, then optimizes a 3DGS scene from that initialization while jointly refining the poses. Its prior is likewise learned from large-scale data rather than taken from the object at hand. Our method instead imposes a strict, explicit prior from the object’s CAD model.

## 2.2 Classical Mesh Texturing

Prior to neural rendering, classical multi-view stereo decoupled geometry from texture mapping. Given a reconstructed or known mesh, MVS-Texturing [19] adds texture from input images onto fixed 3D geometry by solving a Markov Random Field (MRF) optimization to assign textures from an optimal view to each face, using local color adjustments to hide seams. While computationally eficient, these methods are exceptionally sensitive to sparse overlaps, pose inaccuracies, and lack support for view-dependent appearance. In practice, therefore, they are fragile and often produce fragmented, inconsistent textures.

## 2.3 Mesh Anchoring

A growing body of work couples Gaussian primitives with mesh-based structures because of their potential to integrate with existing 3D workflows. SuGaR [20] regularizes splats toward a surface to enable mesh extraction, GaMeS [21] parameterizes splats on mesh faces for editing, and

GaussianAvatars [22] rigs splats to a parametric head template for animation. These methods anchor splats to a mesh that is either extracted from dense captures or given in known alignment; we instead anchor to a retrieved CAD model whose pose relative to the cameras is initially unknown, and use the anchoring as a sparse-view regularizer and an explicit link back to the object’s design. Relatedly, deformation fields have been used to model dynamic motion in video [23, 24]; we repurpose this architecture for static alignment between the canonical CAD space and the physical observations [25].

## 2.4 Pose Estimation and CAD-Based Tracking

Traditional SfM (COLMAP [26]) expresses camera poses relative to one another, up to a global similarity transformation, without any notion of objects. Per-object model-based trackers [27] solve this camera-to-object problem by matching edge features to a projected CAD model, but require a separate pre-training step for every CAD object and often fail to overcome the appearance discrepancy between textureless CAD models and real imagery, returning no viable pose in such cases. Category-level estimators based on Normalized Object Coordinate Space (NOCS) [28] instead regress a canonical-space correspondence and recover a pose against any retrieved CAD model. We adopt a related but lighter-weight strategy for pose initialization: rather than training a per-pixel coordinate regressor, we compare the silhouettes of each candidate CAD model from a dense grid of viewpoints to the object silhouettes in the sparse-view capture, and aggregate the per-view matches into a single multi-viewconsistent registration of the calibrated capture. This shares the practical properties that make NOCS attractive, without requiring any learned per-pixel predictor. However, as with NOCS, the resulting poses are rather coarse, necessitating further joint-pose refinement (section 3.3).

## 2.5 CAD Model Retrieval and Alignment

A separate line of work picks a CAD model from a repository and aligns it to images of a real scene. Scan2CAD [29] learns 9-DoF alignment between

CAD models and RGB-D scans; Mask2CAD [30] and ROCA [31] predict both the model and its pose from a single RGB image, with networks trained on those scan annotations; SPARC [32] improves a single-image alignment by repeatedly rendering it and comparing it to the image; and DifCAD [33] learns the same task from synthetic data only. These methods are built for cluttered indoor rooms; they require trained per-category predictors and hand-annotated alignments, and the single-image methods process one frame at a time. Our setting is diferent: a handful of wide-baseline views of a single object, already calibrated relative to each other. Rather than working with pretrained models that regress camera poses, we perform silhouette matching to propose a pose for each view and use the existing relative calibration to retain mutually consistent proposals. What comes out is a camera-to-object registration of the whole capture, which we then refine together with the reconstruction.

## 2.6 Joint Novel-View Synthesis and Pose Estimation

Analysis-by-synthesis methods such as iNeRF [34] and BARF [35] optimize poses and radiance fields simultaneously but require dense image captures. Pose-free pipelines such as NoPe-NeRF [36] and COLMAP-Free 3DGS [37] remove the SfM preprocessing step altogether but are limited in applicability to video captures, as they assume temporal ordering and small inter-frame distances.

NeRS [38] targets exactly the sparse, widebaseline, in-the-wild regime we address. It represents the object as a neural deformation of a unit sphere [39, 40], discretized into a mesh and Phongshaded, and jointly optimizes shape, appearance, and camera parameters from roughly 8 views. Instead of deforming a generic sphere, we retrieve an actual CAD model, which both strengthens the geometric prior and provides a canonical frame for the cameras, enabling multiple new applications. Finally, our method inherits 3DGS’s real-time rendering, whereas NeRS remains expensive to render. Methodologically related to our work is CAD-NeRF [41]. We share the high-level idea of using a CAD repository for shape selection and pose initialization, but difer in three ways: (1) we adopt 3DGS rather than a NeRF density field, enabling surface-aligned initialization and real-time rendering; (2) our geometry stays a smooth deformation of the CAD surface—splats can only move through one shared, smooth deformation field, so no splat can drift of on its own into empty space to explain a single training view—whereas CADNeRF only softly regularizes an occupancy field and can still leave density in free space; and (3) our joint pose optimization absorbs coarse silhouette-matching hypotheses without CADNeRF’s ordered-image multi-view pose retrieval or its assumption that all cameras observe the object from a similar distance. Closely related in spirit, CADSim [42] reconstructs vehicles for self-driving sensor simulation from sparse, noisy in-the-wild multi-camera and LiDAR data by optimizing a part-aware CAD mesh with a diferentiable renderer; it shares our use of CAD priors and joint pose refinement under sparse observation. Its priors, however, are inherently vehicle-bound: a curated set of part-annotated vehicle CAD models and a wheel-articulation model, so applying it to any other object category would require redesigning the method. Our prior is simply a retrieved CAD model, which applies to any category covered by a shape repository.

## 3 Methodology

Our goal is to reconstruct a photorealistic 3D asset and recover precise 6-DoF camera-to-object poses from a sparse set of images $\textit { \textbf { Z } } = \ \{ I _ { 1 } , \ldots , I _ { N } \}$ with a known relative calibration, i.e., camera poses relative to one another obtained from manual pre-calibration or Structure-from-Motion. As shown in Figure 2, given a library of candidate CAD models, we retrieve the most similar CAD mesh and a coarse camera-to-object registration of the calibrated camera trajectory to its canonical frame by matching the observed object silhouettes against the CAD library’s masked renderings (section 3.2), which is later refined diferentiably (section 3.3). We anchor our Gaussian primitives strictly to the surface of the retrieved CAD mesh (section 3.4), accounting for potential geometric discrepancies between the CAD model and observations of the physical object via a learnable non-rigid deformation field (section 3.5). Our optimization pipeline (section 3.6) proceeds in two stages: a Geometric Warmup that optimizes the pose estimates and the deformation field diferentiably to align the ground-truth segmentation masks with the rendered alpha channel, followed by a Photometric Finetuning stage that recovers view-dependent appearance by optimizing 3DGS attributes.

## 3.1 Preliminaries: 3D Gaussian Splatting

We adopt 3D Gaussian Splatting (3DGS) [2] as our underlying representation. Each 3D Gaussian $g _ { i }$ is defined by a center position $\mu _ { i } \in \mathbb { R } ^ { 3 }$ , three scaling factors $s _ { i } ~ \in ~ \mathbb { R } ^ { 3 }$ , a rotation quaternion $q _ { i } \in \mathbb { R } ^ { 4 }$ , and an opacity value $\alpha _ { i } \in \mathbb { R }$ . The viewdependent color is parameterized using spherical harmonics (SH) coeficients. To render an image, the 3DGS primitives are projected into screen space using splatting and α-blending.

## 3.2 Silhouette-Based CAD Matching

Our pipeline begins with the relative calibration: a pre-calibrated rig or an SfM run on the sparse training views. This calibration is expressed in an arbitrary coordinate frame, locating the cameras relative to one another but not to the object. Silhouette matching identifies the most similar CAD model and anchors the camera poses in the canonical frame of the matched object by comparing observed object silhouettes with mask renderings from a CAD model library.

For each posed input image of the sparse-view capture, we extract a binary foreground mask $M _ { G T }$ with the Segment Anything Model 3 (SAM3) [43]. While this may seem like a tedious step, querying objects based on text prompts works well in practice, and in static multi-camera setups, obtaining object masks of moving objects is trivial. We then query a library of candidate CAD models. Each candidate is rendered with white textures, no environment lighting, and a black background, using a dense grid of viewpoints sampled over the viewing sphere. To compare silhouettes independently of where the object appears in the image or how large it is, we normalize every mask—both the rendered library silhouettes and the observed SAM3 masks—by cropping it to its tight bounding box and resizing it into a fixedsize square canvas while preserving aspect ratio.

![](images/b70b5932dd2476f216f74f06b36f2db5ce51746ea02af3770bc4dfba62c8bd92.jpg)  
Fig. 2 CADSplat overview. Object silhouettes from SAM3 [43] are matched against renderings of a CAD library to retrieve the most similar model and coarse camera-to-object poses. 3D Gaussians are sampled on the retrieved mesh, and the deformation network, camera correction, and 3DGS parameters are then optimized jointly. During the geometric warmup, only the rendered alpha channel is supervised against the mask $M _ { G T } \ ( \mathcal { L } _ { m a s k } )$ ; afterward, the rendered RGB is compared with the masked photographs $( \mathcal { L } _ { p h o t o } )$

For each observed mask, we retain the top 50 viewpoints whose normalized silhouettes achieve an Intersection-over-Union (IoU) of 0.7 or higher as camera-to-object pose hypotheses. We render this viewpoint grid once per library, ofline and in parallel, before any capture is taken. Matching a new capture then only compares its masks against these stored silhouettes.

These per-image hypotheses do not replace the need for the relative calibration, as they are individually unreliable. A silhouette does not uniquely determine a pose when objects are near symmetric from some viewpoints. The viewpoint library is also discrete, so the true viewing angle generally falls between the sampled angles, and an incorrect pose can then score a higher IoU than the correct one. We therefore never use these hypotheses in isolation. Instead, we combine them with the relative calibration information, treating it as a consistency filter. Concretely, we use RANSAC over Sim(3). Each iteration samples one pose hypothesis from each of two randomly sampled images and computes the transformation to register the relative calibration into the object’s canonical frame (rotation and translation from the first hypothesis, scale from the ratio of inter-camera distances).

It then scores the candidate by rendering the CAD silhouette in all views and accumulating per-view IoU scores. The CAD model M and transformation $\mathbf { T } _ { i n i t }$ with the highest aggregate support are then selected. Applying $\mathbf { T } _ { i n i t }$ to the relatively calibrated cameras yields the initial per-camera camera-to-object poses $\mathbf { T } _ { i n i t } ^ { \left( i \right) }$ . In this way, a single discriminative viewpoint sufices to anchor the trajectory correctly, even when other views are individually ambiguous. Figure 3 makes the difference visible: our consensus registration places the cameras in a consistent ring around the object (fig. 3a), whereas matching each camera to its closest library silhouette independently scatters them incoherently (fig. 3b).

Note that this registration works well even for texture-less or reflective objects: the relative calibration can rely predominantly on background features in such cases, while silhouette matching consumes only silhouettes and is therefore unafected by material properties.

## 3.3 Camera Pose Optimization

The silhouette-based registration from section 3.2 is only coarsely accurate and must be refined jointly with the reconstruction. We model this as a learnable pose correction optimized together with the reconstruction. When the relative calibration is accurate, as on our own SCO-CAD dataset (section 4.2), a single global correction $\Delta \mathbf { T } _ { g }$ shared by all cameras sufices:

![](images/4966c6c96395f90cb2c94426ffeaee6d2da7f619247dd997bcdbddde2fbd01b2.jpg)

(a) Multi-view consensus registration (ours)  
![](images/aa5af916e5f59586966262b1d13ff4a9a5be366762d06f276500701b81321f1c.jpg)  
(b) Independent per-camera silhouette matching  
Fig. 3 Joint versus independent camera-to-object registration. (a) Our consensus registration (section 3.2) recovers one similarity transform for the whole calibrated trajectory, so the initial poses $\mathbf { T } _ { i n i t }$ (red) form a consistent ring around the CAD model, which the joint optimization (section 3.3) refines to $\mathbf { T } _ { o p t }$ (green). (b) Matching each camera independently to its best library silhouette scatters the cameras: a silhouette alone does not fix a viewpoint, so each view picks a diferent, often mirrored, orientation. Using the relative calibration as a RANSAC consistency filter removes these mutually inconsistent matches.

$$
\mathbf { T } _ { o p t } ^ { \left( i \right) } = \Delta \mathbf { T } _ { g } \mathbf { \cdot S } _ { s } \big ( \mathbf { T } _ { i n i t } ^ { \left( i \right) } \big ) , \qquad \Delta \mathbf { T } _ { g } = \left[ \mathbf { R } _ { \delta } ( \pmb { r } _ { \delta } ) \mathbf { \Delta } t _ { \delta } \right]\tag{1}
$$

where $\mathbf { S } _ { s }$ scales the camera center by a learnable scalar $s ~ = ~ \exp ( \Delta s )$ that absorbs the unknown scale between the calibrated trajectory and the CAD canonical frame. For a camera-to-world pose $\left( \mathbf { R } _ { i } , \mathbf { c } _ { i } \right)$ this means ${ \bf c } _ { i } \ \mapsto \ { \bf R } _ { \delta } ( s { \bf c } _ { i } ) + t _ { \delta }$ and $\mathbf { R } _ { i } \mapsto \mathbf { R } _ { \delta } \mathbf { R } _ { i }$ . Following Zhou et al. [44], the rotation is parameterized as a continuous 6D vector $\pmb { r } _ { \delta } ~ \in ~ \mathbb { R } ^ { 6 }$ mapped to $\mathbf { R } _ { \delta } ~ \in ~ S O ( 3 )$ via Gram– Schmidt to avoid the discontinuities of Euler angles or quaternions. All ten parameters (translation, 6D rotation, log-scale) are initialized to the identity correction. When the provided poses are themselves per-view unreliable rather than only globally misaligned, as in the NeRS [38] datasets, the same module instead learns an independent correction $\Delta \mathbf { T } ^ { ( i ) }$ per camera.

## 3.4 Geometric Initialization

Rather than initializing the 3DGS representation from the SfM sparse point cloud, we sample splats directly from the retrieved CAD mesh M. We define a target number of primitives $N _ { s p l a t s }$ and draw an area-weighted uniform random sample of points from the mesh surface to obtain the initial canonical positions $\mu _ { i } ^ { c a n }$ . The associated surface normals $n _ { i }$ are recovered by casting a ray from each sample back toward the mesh interior and reading the triangle normal of the intersected face. We initialize the rotation quaternion $q _ { i }$ of each Gaussian to the shortest-arc rotation that aligns its local z-axis with $n _ { i } ,$ so each primitive begins as an oriented disk tangent to the mesh surface. This provides a strong initial inductive bias. Importantly, we do not employ densification or pruning strategies (e.g., cloning or splitting) used in standard 3DGS.

## 3.5 Deformable Mesh-to-Reality Alignment

To correct discrepancies between the shape of M and the physical objects depicted in the images — whether because no exact CAD model is present in the CAD library or due to manufacturing tolerances or errors — we introduce a coordinate-based deformation network $\mathcal { D } _ { \theta }$ similar to Yang et al. [24]. $\mathcal { D } _ { \theta }$ is parametrized by a Multi-Layer Perceptron (MLP) with $D = 8$ layers, width $W = 2 5 6$ , and a skip connection at the middle layer as depicted in Fig. 4.

The network takes the canonical splat position $\mu$ as input and predicts a position ofset $\Delta \mu \colon$

$$
\Delta \mu = { \mathcal { D } } _ { \theta } ( \gamma ( \mu ) ) ,\tag{2}
$$

where $\gamma ( \cdot )$ is a sinusoidal positional encoding. The final deformed position of the splat in world space

![](images/b999bf04eb1df0f6bb08d749033f68f06941d8981fc5e2c4092f3aec4b556aa3.jpg)  
Fig. 4 Architecture of the deformation network ${ \mathcal { D } } _ { \theta } .$ The network maps a canonical coordinate $\mu$ to highdimensional features via an 8-layer MLP. A skip connection injects the positional encoding at Layer 4. A single linear head then predicts the position ofset $\Delta \mu$

is given by:

$$
\mu ^ { \prime } = \mu + \Delta \mu .\tag{3}
$$

The output head is initialized such that $\Delta \mu \approx 0$ at the start of training. Note that we define the deformation in the canonical space. Therefore, the learned deformation represents a correction to the mesh shape shared across all viewpoints. Because $\mathcal { D } _ { \theta }$ is a smooth coordinate MLP predicting ofsets from this shared canonical shape, it injects a spatial smoothness prior that standard 3DGS lacks, which helps in avoiding overfitting deformations to sparse training views.

## 3.6 Optimization Pipeline

Attempting to jointly learn pose, deformation, and color from a noisy initialization can lead to local minima in early stages. We therefore decouple the geometric and photometric objectives into a Geometric Warmup phase, which itself is split into a pose-only sub-phase and a pose-plus-deformation sub-phase, followed by a Photometric Finetuning phase (fig. 5). Throughout training, the per-splat means, and the normal-aligned rotations $q _ { i }$ are frozen, so that the deformation field absorbs all geometric corrections and the primitives remain surface-tangent-oriented disks.

## 3.6.1 Stage I: Geometric Warmup via Mask Alignment

In Stage I, the objective is purely geometric: aligning camera poses and shape to the silhouettes. We render the splats with the 3DGS rasterizer and compare the alpha channel A of the rendered RGBA image with the object masks $M _ { G T }$ from section 3.2 using an $L _ { 1 }$ loss:

$$
\mathcal { L } _ { m a s k } = \| A - M _ { G T } \| _ { 1 } .\tag{4}
$$

For the first 3,000 iterations, only the camerapose delta is optimized; the deformation network is held at its zero-init identity, so it does not start absorbing the pose error. Between 3,000 and 6,000 iterations, we additionally enable the deformation network, which then begins “wrapping” the CAD silhouette onto the observed mask while the pose continues to be refined.

## 3.6.2 Stage II: Photometric Finetuning

After 6,000 total Stage-I iterations, Stage II enables the photometric optimization of the 3DGS primitives. We optimize the view-dependent color (Spherical Harmonics), per-splat scales, and opacities to capture the object photorealistically, while jointly updating pose and deformation using $\mathcal { L } _ { m a s k }$ . To isolate the object and prevent memorization of environmental artifacts, the RGB image is rendered with a random background and compared with the ground-truth image, with the background region replaced by the same random color. The resulting masked photometric loss combines $L _ { 1 }$ and D-SSIM on the RGB channels:

$$
\begin{array} { r } { \mathcal { L } _ { r g b } = ( 1 - \lambda ) \mathcal { L } _ { 1 } + \lambda \mathcal { L } _ { D - S S I M } . } \end{array}\tag{5}
$$

## 3.6.3 Sparse-View Appearance Regularizers

Even with the geometry pinned to the CAD manifold, the photometric loss alone leaves the persplat appearance severely underdetermined in the sparse-view regime. We therefore add two complementary regularizers that act on the appearance parameters during Stage II, yielding the total Stage-II objective

$$
{ \mathcal { L } } _ { p h o t o } = { \mathcal { L } } _ { r g b } + \lambda _ { m a s k } { \mathcal { L } } _ { m a s k } + \lambda _ { S H } { \mathcal { L } } _ { S H } .\tag{6}
$$

SH neighbor smoothness: At initialization, we precompute the indices of the $K { = } 2 0$ nearest neighbors of every splat i in the canonical CAD frame; we denote this set $\mathcal { N } ( i )$ . Throughout Stage II, we add an SH smoothness term that penalizes the squared diference between every splat’s SH coeficient vector $c _ { i } = ( c _ { i } ^ { ( 0 ) } , \dots , c _ { i } ^ { ( N ) } )$ and that of each of its precomputed neighbors:

$$
\mathcal { L } _ { S H } = \frac { 1 } { N K } \sum _ { i = 1 } ^ { N } \sum _ { j \in \mathcal { N } ( i ) } \| c _ { i } - c _ { j } \| _ { 2 } ^ { 2 } .\tag{7}
$$

![](images/0fa651682b63198d385fee7c514a580abfcad3a5d12f4707791dfabc22d257fb.jpg)  
Fig. 5 Evolution of the CADSplat Optimization process. (Top) The visual state of the 3DGS representation at key iteration milestones. (Bottom) The active optimization parameters over the course of training.

Because the neighbor set is fixed in canonical space, the loss is invariant to the (small) deformations $\Delta \mu$ and acts as a graph Laplacian on appearance over the CAD surface.

Stochastic splat dropout: To further prevent any single splat from over-committing to a particular training view, at each Stage II iteration, we randomly subsample a fraction $p _ { \mathrm { d r o p } }$ of the splats uniformly without replacement and rasterize only the surviving subset. The mask-loss render in the same iteration uses the undropped set, so dropout regularizes appearance only and never destabilizes silhouette supervision. Because the surface is densely tessellated by ∼ 600k splats, the rendered silhouette and texture remain stable under random subsampling. In contrast, every splat is forced to share the explanation of each observation with its CAD-surface neighbors. We drop half the splats at the start of Stage II and reduce that fraction to zero over the first 20k iterations using a cosine schedule, leaving the last 4k iterations without any dropout. The regularization is thus strongest early, when the per-splat colors are least determined, and the final fit uses every splat.

## 4 Experiments and Evaluation

We evaluate CADSplat on three object-centric datasets to demonstrate its broad applicability: SCO-CAD, our own dataset of sparse captures of common physical objects paired with approximate CAD models, and the two publicly available datasets of NeRS [38]: NeRS MVMC and

NeRS Misc. All datasets are annotated with ground-truth segmentation masks.

## 4.1 Implementation Details

We implement CADSplat on top of the gsplat 3DGS framework. We initialize $N _ { s p l a t s } { = } 6 0 0 { , } 0 0 0$ Gaussian primitives on the canonicalized CAD mesh surface, with their initial log-scales set so each splat covers the mean distance to its three nearest neighbors, their quaternions set to the shortest-arc rotation aligned with the surface normal, and their opacities initialized to the post-sigmoid activation 0.5.

As we lock Gaussian mean optimization and the per-splat quaternions entirely, geometric corrections are absorbed by the coordinate-based deformation field $\mathcal { D } _ { \theta }$ , optimized with Adam at a learning rate of $1 . 6 \times 1 0 ^ { - 5 }$ ; the global pose correction, initialized from the silhouette-based consensus registration, is optimized with Adam at a learning rate of $5 \times 1 0 ^ { - 4 }$ . The optimization pipeline trains for 30,000 iterations: an initial 3,000-iteration pose-only sub-phase, a subsequent 3,000-iteration pose-plus-deformation sub-phase, and a final 24,000-iteration photometric finetuning phase, during which pose, deformation, and the 3DGS parameters are optimized jointly. Table 1 lists the complete set of hyperparameters; all optimizers are Adam.

## 4.2 The SCO-CAD Dataset

SCO-CAD—Sparse Common Objects with associated CAD models—consists of 6 real-world objects. Authentic industrial CAD models are typically protected by strict corporate intellectual property (IP) rights. To avoid leaking sensitive, proprietary data, we deliberately constructed our dataset using common physical objects (e.g., a skateboard or scissors) for which approximate CAD models are publicly available under Creative Commons licenses. A direct consequence of this choice is that the associated CAD models often exhibit noticeable geometric deviations from the physical objects they capture. However, this intentional ”reality $\mathrm { g a p } ^ { \mathrm { , } \mathrm { , } }$ serves as an excellent stress test, necessitating and demonstrating the robustness of our non-rigid deformation network (D ). The six objects, along with their CAD models, will be released together with the full pipeline code. The CAD library for this dataset is the small set of these six approximate models, and every capture may pick any of them. We test large-scale retrieval on NeRS MVMC, where the library is the full ShapeNetCore [5] car category (3,533 models), and NeRS Misc using the other ShapeNetCore categories.

Table 1 Hyperparameters used in all experiments. The splat count is fixed (no densification or pruning); the dropout fraction is cosine-annealed from its initial value to 0 over the first 20k Stage-II iterations.
<table><tr><td>Group</td><td>Parameter</td><td>Value</td></tr><tr><td rowspan="3">Representation</td><td>splat count  $N _ { s p l a t s }$ </td><td>600,000</td></tr><tr><td>SH degree</td><td>3</td></tr><tr><td>means / quaternions</td><td>frozen</td></tr><tr><td rowspan="2">Retrieval</td><td>hypotheses per view</td><td>top 50</td></tr><tr><td>silhouette IoU threshold</td><td>0.7</td></tr><tr><td rowspan="2">Deformation</td><td>MLP depth D / width W</td><td>8  /  256</td></tr><tr><td>PE frequency bands</td><td>10</td></tr><tr><td rowspan="4">Losses</td><td>D-SSIM weight λ</td><td>0.2</td></tr><tr><td>λmask /λSH</td><td>1.0 / 1.0</td></tr><tr><td>SH neighbors K</td><td>20</td></tr><tr><td>initial dropout pdrop</td><td>0.5</td></tr><tr><td rowspan="6">Learning rates</td><td>deformation  $\mathcal { D } _ { \theta }$ </td><td> $1 . 6 \times 1 0 ^ { - 5 }$ </td></tr><tr><td>pose correction</td><td> $5 \times 1 0 ^ { - 4 }$ </td></tr><tr><td>scales</td><td> $5 \times 1 0 ^ { - 3 }$ </td></tr><tr><td>opacities</td><td> $5 \times 1 0 ^ { - 2 }$ </td></tr><tr><td>SH degree 0</td><td> $2 . 5 { \times } 1 0 ^ { - 3 }$ </td></tr><tr><td>SH degrees 1–3</td><td> $1 . 2 5 \times 1 0 ^ { - 4 }$ </td></tr><tr><td rowspan="4">Schedule</td><td>Stage I: pose only</td><td>3k iters</td></tr><tr><td>Stage I: pose + deform</td><td>3k iters</td></tr><tr><td>Stage II: photometric</td><td>24k iters</td></tr><tr><td>test-time refinement</td><td>400 steps</td></tr></table>

Poses and calibration: We recover the relative calibration strictly from the sparse training images using the hierarchical localization pipeline HLoc [4] with learned features and matching [3], which is markedly more robust than traditional SIFT features [45] in the wide-baseline sparse regime, and register this trajectory to the CAD canonical frame with the silhouette-based consensus registration of section 3.2, refining a single global Sim(3) during training (section 3.3). At no point does the method observe poses or points derived from dense capture. This departs deliberately from the evaluation protocol common in sparse-view NVS [7, 8], in which the sparse training views are subsampled from a densely captured scene together with the camera poses (and often the SfM point cloud) computed from that dense capture—inputs that could not exist in a genuine sparse capture.

Ground-truth views for evaluation: Each object is captured as a single dense video, from which we extract the 9–13 training frames. The complete video is calibrated with COLMAP [26] and serves as ground truth for evaluation only; the held-out views used for evaluation are all frames of this trajectory except those used for training. The sparse HLoc calibration (training views) and the dense COLMAP calibration (training and heldout views) reside in diferent coordinate frames. We bridge them with a 7-DoF Umeyama alignment [46] fitted to the training-camera centers, which appear in both.

## 4.3 Evaluation Protocol and Metrics

Evaluating object-centric reconstructions from a genuinely sparse capture raises two dificulties that standard novel-view-synthesis benchmarking does not have: relative calibration discrepancies between training and testing images and a fair comparison between object-level algorithms such as ours and NeRS [38], and scene-level algorithms such as FSGS [7] and InstantSplat [18].

If the training and testing relative calibration do not align perfectly, renders will be shifted by a few pixels relative to their ground-truth photograph. Figure 6 shows what this shift does at the object boundary: the ground-truth and rendered silhouettes disagree in a thin band, which is penalized heavily by pixel metrics, even when the reconstruction itself is accurate. This changes the question the evaluation asks. Standard novel-view synthesis asks whether a method reproduces the test photograph exactly at its given camera pose. With two independent calibrations, that camera is itself uncertain by a few pixels. We therefore reframe the evaluation to ask whether the object renders accurately from a camera near its nominal pose—in other words, whether the reconstructed object is right. Following NeRS [38], we refine each held-out camera individually for 400 optimization steps against its own target view with the reconstruction frozen: only the per-camera pose delta is learnable, so the reconstruction cannot be fitted to the held-out views. All metrics are reported with refinement (table 2) and without it (table 3); the diference reflects the portion of each score attributable to pose alignment rather than reconstruction quality.

![](images/f39b3fc4e369957d8e837616119dc1dcfec0d3032a9856be38674fe4e3604b50.jpg)  
Ground truth

![](images/5b60ff1b04c3a12e6aa518110f321a95fac4df12742c1cb3e52c6efe843d9746.jpg)  
Our render

![](images/eb46f1977d5a9899232bde308d9d82c70a94093840abe2550b09abe077da2e3d.jpg)  
Silhouette overlay  
Fig. 6 Calibration residual on a held-out carjack view. Training and held-out cameras come from two independent calibrations, so the rendered image (middle) is shifted by a few pixels relative to the photograph (left). The overlay (right) shows the shift: white where both silhouettes agree, red where only the photograph shows the object, and blue where only the render shows the object. Pixel metrics penalize these bands heavily, yet say nothing about reconstruction quality, which motivates test-time pose refinement and the eroded-mask metrics in section 4.3.

The second dificulty is that two of our baselines, FSGS [7] and InstantSplat [18], reconstruct the full scene rather than the object. Neither can be turned into an object-centric method: FSGS’s semantic and depth priors need background context, and InstantSplat’s dense stereo model reconstructs whatever is in view. There are diferent ways object-level renders can be compared against scene-level renders, each difering in which pixels from the renders and the ground truth are compared.

Object-crop image quality (PSNR, SSIM, LPIPS, FLIP): This is the evaluation protocol of NeRS [38], and the metrics in which we later report the NeRS datasets (table 7). The ground-truth image is composited onto white using the ground-truth mask, the prediction is rendered as-is over a white background, and both are cropped to the same 10%-padded square around the ground-truth mask and Lanczosresized to 256×256. We report PSNR, SSIM [47], and two perceptual metrics: LPIPS [48] (AlexNet backbone), and FLIP [49]. The advantage of these metrics is that, because the prediction is not masked, any geometry outside the true silhouette is penalized. However, it cannot report performance on full-scene methods as the background would be penalized. We mark such cells as not applicable.

Eroded-mask image quality (mPSNR, mSSIM, mLPIPS, mFLIP, fgPSNR): Here both the ground truth and the prediction are composited onto white using the ground-truth mask before cropping, as used by PixelNeRF [50] and RegNeRF [51] for masked evaluations. We erode the mask by 5 pixels to avoid unreliable segmentation at the silhouette edges. These metrics measure the correctness of the reconstruction inside the ground-truth mask. mPSNR, mSSIM, mLPIPS, and mFLIP are computed on the full image. These metrics still favor scene-level reconstructions as their misaligned band contains background pixels rather than pure white. As a result, we also report fgPSNR as used in CO3D [52], which averages the squared error over the intersection of the rendered and ground-truth masks at full-image resolution, scoring only the foreground.

Masking scene-level renders: For FSGS [7] we additionally segment the foreground object in its renders with SAM3 [43] (manually verified) and use that mask in place of its opacity, so that it is scored on its own silhouette like every objectlevel method. This is reported as FSGS+SAM3. Because these masks are segmented from the poserefined renders, this variant is only reported with test-time refinement.

Silhouette accuracy: Intersection-overunion (IoU) between the predicted mask (pixel opacity >0.5) and the un-eroded ground-truth mask. This quantifies the misalignment between renders and ground truth.

## 4.4 Baselines

We compare against two object-level and two scene-level methods. Vanilla 3DGS [2] is trained on the same mask-composited images as our method, and MVS-Texturing [19] projects the images as textures onto the CAD mesh. FSGS [7] and InstantSplat [18] reconstruct the whole scene. FSGS, vanilla 3DGS, and MVS-Texturing use the same sparse HLoc calibration as our method; InstantSplat estimates its own poses from the training views. Among sparse-view methods with depth and semantic priors, we chose FSGS over DNGaussian [8] because it is newer and uses a superset of DNGaussian’s priors.

Two related methods are absent from this comparison. CADNeRF [41], the closest CAD-based method, released no code. NeRS [38] assumes objects with smooth materials and a known category prior to operate well. We therefore compare against both on the NeRS MVMC and Misc datasets (section 4.6), using their published numbers and renders.

## 4.5 Quantitative Results

Table 2 reports all results averaged over the six scenes with test-time pose refinement, and table 3 without it. CADSplat achieves the best six-scene average across all metrics. Scored inside the ground-truth mask, FSGS is competitive on pixel metrics but consistently trails on perceptual metrics (mLPIPS 0.046 vs. our 0.031, with ours better on every individual scene; mFLIP 0.057 vs. our 0.048). Once its renders are masked with its own silhouette for a proper objectto-object comparison (FSGS+SAM3), it drops across the board (mPSNR 27.18→24.84, fgPSNR 18.81→16.40, IoU 0.821 vs. our 0.942). Inspecting the qualitative renders, FSGS’s over-smoothed textures are kind to PSNR but visibly worse, as captured by LPIPS and FLIP. Attempting to train FSGS on mask-composited images, with its depth and pseudo-view losses restricted to the mask, confirms that it cannot reconstruct the object without scene context, with PSNR falling from 20.25 to 13.43. We therefore omit this variant from the tables.

Vanilla 3DGS. The vanilla 3DGS baseline— unconstrained masked 3DGS trained on the same background-masked images—trails CAD-Splat everywhere (mPSNR 28.95 vs. 26.63, fgP-SNR 20.36 vs. 18.22, IoU 0.942 vs. 0.913, and lower LPIPS/mLPIPS/mFLIP). The gap is largest on voluminous objects with significant occlusion (car1, carjack, senseo: +2.7 to +3.1 dB mPSNR) and smallest on the flat scissors object (+0.9 dB). The reason the gap between our method and Vanilla 3DGS is not larger is that we train on masked objects and randomize the background colors, which prevents floaters outside the object hull. Training 3DGS on the unmasked sparse training views produces noticeably more artifacts, but that would be an unfair comparison.

MVS-Texturing. Classical texturing of the CAD mesh is the weakest baseline in the comparison: a six-scene average PSNR of 11.77, mPSNR 14.64, fgPSNR 6.83. The textures appear as a patchwork with visible seams; when the pose or CAD shape is inaccurate, faces fail to be textured properly, leading to holes, missing parts, and artifacts. Test-time refinement does not help, as it diverges away from the actual object. Therefore, we only report the metrics without test-time refinement.

InstantSplat. Geometry foundation models extend novel-view synthesis to the sparse-view regime by replacing classical SfM with learned dense stereo. InstantSplat [18] uses MASt3R to predict camera poses and a dense point cloud from the sparse views, then optimizes a 3DGS scene from that initialization while jointly refining the poses. Despite being scored inside the groundtruth mask, it trails our method on every metric (mPSNR 27.9 vs. 29.0, mLPIPS 0.045 vs. 0.031, fgPSNR 19.6 vs. 20.4).

The qualitative comparison (Fig. 7) shows the failure modes behind the numbers. FSGS produces reasonable reconstructions, but its textures are noticeably blurrier and over-smoothed compared to ours. MVS-Texturing [19] struggles with widebaseline views, leading to an inconsistent patchwork of texture fragments: individually correct from their source viewpoints, but with abrupt, incongruous transitions, misalignment artifacts, and untextured mesh regions where no source view provides coverage. A video of our reconstructions rendered along continuous novel-view trajectories across the six scenes is provided as Online Resource 1.

## 4.5.1 Robustness to View Sparsity

To evaluate how gracefully our method degrades under increasingly constrained data regimes, we ablate the number of training views from the full set of 9–13 images down to {8, 5, 3} on SCO-CAD. Naively sampling random images risks selecting clustered, nearby viewpoints, leaving the held-out views to observe regions never seen during training. Therefore, for each scene and each target count, we select the first training image randomly and the other training images by farthestpoint sampling (FPS) over the training-camera centers in the SfM frame. Because the first camera is chosen randomly, we run each scene & number of views configuration with multiple random seeds and report the mean across seeds.

![](images/bbf0b1449cf2b9d59ccbf5355aca5e630adf9a98de26674646d5172229c1d2f9.jpg)  
Fig. 7 Qualitative comparison on sparse-view reconstruction (9–13 images). MVS-Texturing [19] produces an inconsistent patchwork of textures and leaves weakly observed regions untextured. FSGS [7] sufers from over-smoothing. InstantSplat [18] is an SfM-free full-scene method; as it reconstructs the whole scene rather than the object, its tiles are shown composited with the ground-truth mask, and even then, it recovers only a coarse object with distorted geometry and smeared texture. CADSplat (Ours) maintains strict geometric fidelity, preserving sharp edges and accurate textures. Best viewed digitally and zoomed in.

Table 2 Novel-view synthesis on held-out views of SCO-CAD: all metrics (defined in section 4.3), averaged over the six scenes, with test-time pose refinement. Some cells show “–” when the method renders full scenes and has no object silhouette to score for the metric. MVS-Texturing is reported without test-time refinement, which degrades it; its row therefore equals that of table 3.
<table><tr><td rowspan="2">Method</td><td colspan="4">Object crop</td><td colspan="5">Eroded mask</td><td rowspan="2">Silhouette IoU↑</td></tr><tr><td>PSNR↑</td><td>SSIM↑</td><td>LPIPS↓</td><td>FLIP↓</td><td>mPSNR↑</td><td>mSSIM↑</td><td>mLPIPS↓</td><td>mFLIP↓</td><td>fgPSNR↑</td></tr><tr><td>FSGS [7]</td><td></td><td></td><td></td><td>一</td><td>27.183</td><td>0.930</td><td>0.046</td><td>0.057</td><td>18.814</td><td></td></tr><tr><td>FSGS+SAM3</td><td>20.250</td><td>0.861</td><td>0.125</td><td>0.101</td><td>24.836</td><td>0.916</td><td>0.082</td><td>0.064</td><td>16.398</td><td>0.821</td></tr><tr><td>Vanilla 3DGS (masked) [2]</td><td>21.244</td><td>0.852</td><td>0.072</td><td>0.092</td><td>26.625</td><td>0.907</td><td>0.044</td><td>0.059</td><td>18.222</td><td>0.913</td></tr><tr><td>MVS-Texturing [19]</td><td>11.765</td><td>0.706</td><td>0.355</td><td>0.253</td><td>14.644</td><td>0.813</td><td>0.274</td><td>0.164</td><td>6.827</td><td>0.400</td></tr><tr><td>InstantSplat [18]</td><td></td><td></td><td></td><td></td><td>27.898</td><td>0.930</td><td>0.045</td><td>0.062</td><td>19.552</td><td></td></tr><tr><td>Ours (Full)</td><td>23.239</td><td>0.888</td><td>0.058</td><td>0.075</td><td>28.953</td><td>0.932</td><td>0.031</td><td>0.048</td><td>20.360</td><td>0.942</td></tr></table>

Table 3 Same as table 2 but without test-time pose refinement (Sim(3) alignment only). FSGS+SAM3 is omitted: its evaluation masks are segmented from the pose-refined renders (section 4.3), and the unrefined renders would yield a diferent mask set, so no comparable row exists. The method ranking matches table 2 on eight of ten metrics (mSSIM and mFLIP shift by ≤0.001), so no conclusion depends on the refinement step. “–” as in table 2.
<table><tr><td rowspan="2">Method</td><td colspan="4">Object crop</td><td colspan="5">Eroded mask</td><td rowspan="2">Silhouette IoU↑</td></tr><tr><td>PSNR↑</td><td>SSIM↑</td><td>LPIPS↓</td><td>FLIP↓</td><td>mPSNR↑</td><td>mSSIM↑</td><td>mLPIPS↓</td><td>mFLIP↓</td><td>fgPSNR↑</td></tr><tr><td>FSGS [7]</td><td></td><td></td><td></td><td></td><td>25.375</td><td>0.911</td><td>0.054</td><td>0.066</td><td>17.200</td><td></td></tr><tr><td>Vanilla 3DGS (masked) [2]</td><td>20.929</td><td>0.850</td><td>0.070</td><td>0.091</td><td>26.594</td><td>0.910</td><td>0.040</td><td>0.056</td><td>18.216</td><td>0.920</td></tr><tr><td>MVS-Texturing [19]</td><td>11.765</td><td>0.706</td><td>0.355</td><td>0.253</td><td>14.644</td><td>0.813</td><td>0.274</td><td>0.164</td><td>6.827</td><td>0.400</td></tr><tr><td>InstantSplat [18]</td><td></td><td></td><td></td><td></td><td>23.818</td><td>0.892</td><td>0.061</td><td>0.075</td><td>15.877</td><td></td></tr><tr><td>Ours (Full)</td><td>21.077</td><td>0.851</td><td>0.068</td><td>0.091</td><td>26.725</td><td>0.910</td><td>0.038</td><td>0.057</td><td>18.404</td><td>0.922</td></tr></table>

Table 4 Impact of view sparsity on reconstruction quality, averaged over the six scenes of SCO-CAD and (per scene) over the FPS seeds, under the evaluation protocol of section 4.3. Training views are selected by farthest-point sampling over camera centers; held-out views are the full held-out trajectory. The all-view row equals the Ours row of table 2.
<table><tr><td rowspan="2">Views</td><td colspan="4">Object crop</td><td colspan="4">Eroded mask</td><td colspan="2">Fg / Sil.</td></tr><tr><td>PSNR↑</td><td>SSIM↑</td><td>LPIPS↓</td><td>FLIP↓</td><td>mPSNR↑</td><td>mSSIM↑</td><td>mLPIPS↓</td><td>mFLIP↓</td><td>fgPSNR↑</td><td>IoU↑</td></tr><tr><td>3 Views</td><td>20.710</td><td>0.845</td><td>0.122</td><td>0.116</td><td>25.171</td><td>0.898</td><td>0.083</td><td>0.084</td><td>17.012</td><td>0.929</td></tr><tr><td>5 Views</td><td>21.987</td><td>0.865</td><td>0.089</td><td>0.097</td><td>26.859</td><td>0.912</td><td>0.057</td><td>0.070</td><td>18.534</td><td>0.940</td></tr><tr><td>8 Views</td><td>22.568</td><td>0.876</td><td>0.073</td><td>0.086</td><td>27.871</td><td>0.921</td><td>0.045</td><td>0.059</td><td>19.410</td><td>0.942</td></tr><tr><td>All Views (9–13)</td><td>23.239</td><td>0.888</td><td>0.058</td><td>0.075</td><td>28.953</td><td>0.932</td><td>0.031</td><td>0.048</td><td>20.360</td><td>0.942</td></tr></table>

![](images/7732d1f387d53bca9c923b56a15bf2714fb057f7f7f4ca0ea4eeb3004ca0a96f.jpg)  
Fig. 8 Qualitative evaluation of CADSplat across varying numbers of training views. Because the geometry is constrained by the CAD prior, the reconstruction degrades gracefully to blurrier textures rather than generating geometric hallucinations, even in extremely sparse regimes.

Held-out views are scored with the full protocol of section 4.3, and all other hyperparameters are unchanged from section 4.1. One caveat must be stated explicitly: the reduced-view conditions reuse the relative calibration and silhouette registration of the full sparse (9-13 views) capture. A genuine 3-view capture would have to calibrate from those three wide-baseline images alone, which often exceeds what current SfM can deliver. This experiment, therefore, models the pre-calibrated-rig regime—where calibration is available regardless of how many views are captured—and measures how reconstruction quality degrades as views are removed.

Table 4 presents the quantitative degradation averaged over the six scenes, and Fig. 8 a qualitative visualization comparing novel viewpoints across view counts. We notice that our method degrades gracefully as views are removed. The decreased performance is concentrated mostly on appearance, not geometry: from all views down to three, the silhouette IoU falls only from 0.942 to 0.929 (a 1.4% relative drop), whereas the perceptual distance mLPIPS grows 2.7× (0.031 → 0.083) and fgPSNR drops 3.3 dB (20.36 → 17.01). Scarcity thus shows up as a noisier texture on a stable surface rather than as broken geometry. The per-scene breakdown shows that degradation depends on the object shape: geometrically simple objects where most of the shape is visible in a single image (hammer, scissors) are essentially saturated by 8 views—hammer’s 8-view PSNR (25.38) even marginally exceeds its all-view score (25.26), and scissors gains under 0.2 dB from 5 views onward—while more voluminous objects with significant per-image occlusion degrade more significantly. Even in the extreme 3-view regime, the metrics remain usable (PSNR 20.7, mPSNR 25.2, IoU 0.93). A video sweeping novel views at each view count is provided as Online Resource 2.

## 4.5.2 Initialization: CAD Mesh vs. a Generic Sphere

To isolate the CAD model’s contribution relative to the other pipeline components, we replace the mesh initialization with a sphere while keeping everything else identical. The sphere is positioned at the intersection of the cameras’ viewing directions and rescaled to cover the same surface area as the ground-truth masks. To our genuine surprise, at the full view budget, the sphere initialization is not merely competitive but slightly ahead of the CAD initialization on the six-scene average of every metric (table 5: PSNR 23.54 vs. 23.24, mPSNR 29.40 vs. 28.95, IoU 0.946 vs. 0.942). We report this openly, as it is informative rather than adverse: when 9–13 views are available, the photometric and silhouette signals are suficiently rich for the deformation field to carve the object out of a featureless sphere as well as from the CAD mesh.

The CAD prior becomes meaningful as views become scarce. table 5 shows that as views decrease, initializing shape from CAD models becomes more important: at 3 views the CAD initialization gives +1.4 dB PSNR, +1.1 dB mPSNR, +1.0 dB fgPSNR, and a +4.9-point silhouette-IoU gap (0.929 vs. 0.879). From only three images, the sphere cannot recover a correct silhouette without a shape prior, which the CAD prior supplies. The advantage of CAD initialization is especially visible in the group of voluminous objects with significant occlusion. The reason is clear: a generic sphere cannot infer the parts of a voluminous object that no training view observes from more than one angle—precisely the geometry the CAD prior fills in. The prior’s value is therefore geometric disambiguation under occlusion and scarcity.

Rather than undermining our method, the sphere result is a testament to the strength of constrained deformation in producing highfidelity, well-isolated objects. It generalizes better to held-out views than unconstrained masked 3DGS in sparse-view scenarios. Sphere-initialized CADSplat exceeds the vanilla 3DGS baseline of table 2 by +2.8 dB mPSNR, +2.6 dB fgPSNR, and +0.03 IoU at the full budget.

## 4.5.3 Ablation of Design Decisions

Table 6 isolates each component’s contribution as a six-scene average, accumulating one component at a time from the bare CAD-plus-masked ground truth baseline (PSNR 17.94, IoU 0.79) to the full method (PSNR 23.24, IoU 0.94).

Efect of Deformation: Disabling the deformation network $\mathcal { D } _ { \theta }$ forces the system to treat the CAD model as perfectly rigid, so residual CADto-object mismatch surfaces as ghosting (fig. 9). Deformation alone recovers most of the fidelity— PSNR 22.92, mPSNR 28.38, IoU 0.941, within 0.3 dB of the full method—as the field “wraps” the CAD mesh onto the physical observation and can autonomously correct for pose misalignment by rigidly deforming the object to match camera viewpoints. However, because we care about the correctness of camera-to-object poses as well, we also include a separate pose optimization step.

Efect of Pose Optimization: Refining a single global Sim(3) during training mitigates inaccuracies from the consensus registration. On its own, it reaches PSNR 22.67. Its marginal gain on top of deformation is small in the six-scene average, but is concentrated in the scenes whose calibration is least accurate. In contrast to the deformation network, it cannot recover non-rigid shape discrepancies, so on its own it only sufices when the CAD model is accurate.

Table 5 Initialization ablation on SCO-CAD: CAD-mesh vs. unit-sphere initialization, six-scene averages at each view count (limited-view rows averaged over the FPS seeds), all else identical. Bold marks the better of the two per column; the winner crosses over from CAD at 3 views to the sphere by 8 views, isolating the CAD prior’s value to the sparse regime.
<table><tr><td rowspan="2">Views</td><td rowspan="2">Init</td><td colspan="3">Object crop</td><td colspan="2">Eroded mask</td><td colspan="2">Fg / Sil.</td></tr><tr><td>PSNR↑</td><td>SSIM↑</td><td>LPIPS↓</td><td>mPSNR↑ mLPIPS↓</td><td>mFLIP↓</td><td>fgPSNR↑</td><td>IoU↑</td></tr><tr><td rowspan="2">3</td><td>CAD</td><td>20.710</td><td>0.845</td><td>0.122</td><td>25.171 0.083</td><td>0.084</td><td>17.012</td><td>0.929</td></tr><tr><td>Sphere</td><td>19.312</td><td>0.830</td><td>0.152</td><td>24.099 0.098</td><td>0.088</td><td>16.005</td><td>0.879</td></tr><tr><td rowspan="2">5</td><td>CAD</td><td>21.987</td><td>0.865</td><td>0.089</td><td>26.859 0.057</td><td>0.070</td><td>18.534</td><td>0.940</td></tr><tr><td>Sphere</td><td>21.711</td><td>0.861</td><td>0.099</td><td>26.992 0.063</td><td>0.070</td><td>18.687</td><td>0.930</td></tr><tr><td rowspan="2">8</td><td>CAD</td><td>22.568</td><td>0.876</td><td>0.073</td><td>27.871 0.045</td><td>0.059</td><td>19.410</td><td>0.942</td></tr><tr><td>Sphere</td><td>22.783</td><td>0.881</td><td>0.074</td><td>28.318 0.043</td><td>0.057</td><td>19.850</td><td>0.942</td></tr><tr><td rowspan="2">All</td><td>CAD</td><td>23.239</td><td>0.888</td><td>0.058</td><td>28.953</td><td>0.048</td><td>20.360</td><td>0.942</td></tr><tr><td>Sphere</td><td>23.535</td><td>0.895</td><td>0.059</td><td>29.403</td><td>0.031 0.030 0.046</td><td>20.807</td><td>0.946</td></tr></table>

Table 6 Ablation of CADSplat’s components, six-scene averages under the protocol of section 4.3. Components accumulate down the table, from the CAD mesh with mask supervision only (first row) to the full method (last row, which equals the Ours row in table 2). “Mask align” is the warmup phase that delays appearance optimization until deformation and pose have settled against the silhouette. Bold marks the best value per column.
<table><tr><td rowspan="2">Configuration</td><td colspan="4">Object crop</td><td colspan="4">Eroded mask</td><td rowspan="2">Fg fgPSNR↑</td><td rowspan="2">Sil. IoU↑</td></tr><tr><td>PSNR↑</td><td>SSIM↑</td><td>LPIPS↓</td><td>FLIP↓</td><td>mPSNR↑</td><td>mSSIM↑</td><td>mLPIPS↓</td><td>mFLIP↓</td></tr><tr><td>No deformation, no pose opt.</td><td>17.944</td><td>0.796</td><td>0.237</td><td>0.155</td><td>21.881</td><td>0.874</td><td>0.135</td><td>0.096</td><td>13.810</td><td>0.793</td></tr><tr><td>Deformation, no pose opt., mask align</td><td>22.917</td><td>0.879</td><td>0.072</td><td>0.076</td><td>28.376</td><td>0.924</td><td>0.041</td><td>0.049</td><td>19.629</td><td>0.941</td></tr><tr><td>No deformation, pose opt., mask align</td><td>22.667</td><td>0.878</td><td>0.081</td><td>0.079</td><td>28.193</td><td>0.925</td><td>0.041</td><td>0.050</td><td>19.505</td><td>0.934</td></tr><tr><td>Deformation, pose opt., no mask align</td><td>18.880</td><td>0.821</td><td>0.217</td><td>0.140</td><td>24.461</td><td>0.897</td><td>0.111</td><td>0.075</td><td>16.231</td><td>0.784</td></tr><tr><td>Deformation, pose opt., mask align</td><td>22.926</td><td>0.879</td><td>0.068</td><td>0.076</td><td>28.412</td><td>0.924</td><td>0.039</td><td>0.049</td><td>19.663</td><td>0.941</td></tr><tr><td>+ SH neighbor smoothness</td><td>23.126</td><td>0.886</td><td>0.061</td><td>0.075</td><td>28.740</td><td>0.930</td><td>0.032</td><td>0.048</td><td>20.183</td><td>0.942</td></tr><tr><td>+ Splat dropout (Ours)</td><td>23.239</td><td>0.888</td><td>0.058</td><td>0.075</td><td>28.953</td><td>0.932</td><td>0.031</td><td>0.048</td><td>20.360</td><td>0.942</td></tr></table>

Efect of Mask Alignment: We investigate whether the geometric warmup is needed, i.e., whether pose and deformation can be learned from the photometric signal directly, alongside the appearance. Without it, the texture is fitted to a still-misregistered surface and the geometry never recovers: the reconstruction collapses to PSNR 18.88 and IoU 0.784, below either geometric component used alone.

Efect of SH Neighbor Smoothness and Splat Dropout: The two appearance regularizers introduced in section 3.6.3 each add a small, consistent gain on top of the joint deformation/pose/alignment baseline. Pulling each splat’s SH coeficients toward those of its 20 canonical-neighbor splats (PSNR 22.93→23.13, mLPIPS 0.039→0.032) removes high-frequency color changes in unobserved views; splat dropout (PSNR 23.13→23.24, fgPSNR 20.18→20.36) ensures that splats occluded in the training views—but visible or sorted diferently in held-out views—still receive an optimization signal.

The visual impact of these decisions is shown in table 6 and fig. 9, and animated across novel views in Online Resource 3.

## 4.5.4 Camera-to-Object Registration Accuracy

The metrics above measure image quality. We also measure the accuracy of recovered camerato-object pose directly, as it matters for downstream applications (section 5). The ground-truth camera-to-object poses are annotated manually. For each scene, we annotate keypoint correspondences between the CAD model and several heldout views, triangulate those keypoints in the dense COLMAP frame, and fit the similarity transform between the triangulated points and their CAD counterparts [46]. This yields a reference pose of the CAD model in the dense frame and, with it, a reference camera-to-object pose for every camera. We report two errors with respect to this reference:

![](images/5ed5dee3b091d52c9f38c9a3a105f52cee9fc88db5f4864e07ac79f363a9ecb2.jpg)  
Fig. 9 Visual ablation study demonstrating the impact of architectural decisions on the reconstruction quality.

the geodesic rotation error of the camera orientations in degrees, and the camera-center error as a percentage of the camera-to-object distance, which makes it independent of the reconstruction’s scale. For the two near-symmetric objects (carjack, skateboard), a silhouette cannot distinguish the object from its 180<sup>◦</sup> rotation, so we report the error against the closer of the two symmetric reference poses. Errors are medians over the training cameras, averaged over the six scenes. The silhouette consensus alone $\left( \mathbf { T } _ { i n i t } \right)$ registers the object to within 6.2<sup>◦</sup> rotation and 18.6% position error (per-scene range 3.1–10.2<sup>◦</sup> and 14–24%), and the joint pose optimization refines this to 2.9<sup>◦</sup> and 6.1% $( \mathbf { T } _ { o p t } ;$ range 1.2–4.2<sup>◦</sup> and $1 . 6 \mathrm { - } 1 4 . 3 \% )$ , reducing both errors on every scene except senseo’s rotation, which is already accurate after the consensus step (3.1<sup>◦</sup> → 3.3<sup>◦</sup>). The largest remaining error is on carjack (4.2<sup>◦</sup>, 14.3%), the scene with the least accurate relative calibration.

## 4.6 NeRS MVMC

The NeRS MVMC dataset [38] consists of 20 sparse-view car listings captured by untrained people who took a few pictures of their cars for online listing. For this dataset, we follow the evaluation methodology established by NeRS [38], performing both qualitative and quantitative evaluation. The pipeline is identical to that on SCO-CAD, except for the camera calibration. SCO-CAD provides an accurate relative calibration, whereas MVMC does not. Its listings are casual internet photos—few, wide-baseline views with inconsistent backgrounds—in which neither COLMAP [26], HLoc [4] nor VGGT [53] could identify poses for all viewpoints. We therefore use the camera-to-object poses shipped with the dataset, as NeRS itself does. These provided poses are only rough per-view estimates, not accurate relative calibrations. Consequently, whereas on SCO-CAD the pose optimization in section 3.3 refines a single global Sim(3), here we let it learn an independent correction for each camera. The CAD library used to find the best shape match is the ShapeNetCore [5] cars category.

We compare against NeRS [38] and CADSim [42], which both report results on this dataset (CADNeRF [41] released neither metrics nor code). All rows of table 7 report the object-crop PSNR/SSIM/LPIPS (section 4.3)—the protocol NeRS established for this dataset and the one in which both baselines publish their numbers. The NeRS row is its strongest published setting (fixed optimized cameras), which matches the percamera test-time refinement we use. CADSim’s row is copied from its paper, as its code is not released. Reading Table 7 fairly requires spelling out how much category-specific knowledge each method builds in, because cars have a very specific appearance, material, and symmetrical properties. Both baselines rely heavily on these priors. NeRS represents shape as a network that maps every point on a unit sphere to a point on the object’s surface, thereby keeping the surface watertight; on MVMC, however, this network is not initialized neutrally but is pre-trained so that the sphere maps onto a category-specific car template mesh before the input images are ever seen. Optimization, therefore, starts from an already car-shaped surface. NeRS further restricts appearance to a Phong reflectance model under a learned environment map—an illumination family that suits smooth, uniformly painted car bodies particularly well. CADSim embeds even stronger priors: it starts from a small curated set of part-annotated vehicle CAD models; it optimizes a vehicle-specific

Ours

NeRS [38]

articulation model in which all wheels share a single mesh, the wheel positions are symmetric by construction; it enforces hard left–right symmetry of the recovered geometry through an explicit symmetric Chamfer loss between the mesh and its own reflection; and where the capture provides it, it additionally consumes LiDAR depth. These priors are highly efective for vehicles and largely meaningless elsewhere. Our pipeline, by contrast, is the same generic one used throughout this paper; its only car-specific ingredient is a soft symmetry assumption over the car’s length. Despite carrying the lightest prior load, our method achieves the best PSNR and SSIM among the comparison methods and improves on NeRS across all three metrics, while also enabling real-time rendering; only CADSim’s LPIPS remains ahead of ours. The qualitative comparison in fig. 10 shows that NeRS’s renders exhibit distorted geometry and smeared textures, whereas ours remain sharp and pose-accurate.

Table 7 Quantitative evaluation on the NeRS MVMC dataset, in the object-crop metrics (section 4.3): the evaluation protocol established by NeRS, in which both baselines publish their numbers. The NeRS row is its strongest published setting (fixed optimized cameras); CADSim’s row is transcribed from its paper, as its code is not released.
<table><tr><td>Method</td><td>PSNR ↑</td><td>SSIM ↑</td><td>LPIPS ↓</td></tr><tr><td>NeRS [38]</td><td>16.5</td><td>0.720</td><td>0.172</td></tr><tr><td>CADSim [42]</td><td>17.7</td><td>0.751</td><td>0.147</td></tr><tr><td>Ours</td><td>18.7</td><td>0.767</td><td>0.157</td></tr></table>

## 4.7 NeRS Misc

The NeRS Misc dataset [38] comprises 8 various household objects captured sparsely in the wild. As in MVMC, we use the camera poses provided with the dataset as the camera-to-object poses. Silhouettes are matched against all ShapeNet-Core [5] categories except cars. Following NeRS, we qualitatively evaluate this set (Fig. 11) and compare against NeRS [38] and CADNeRF [41]. This dataset requires significant deformation from the deformation network, as several objects have no counterpart category in ShapeNetCore. Therefore, the consensus registration selects the closest

GT

![](images/554f49b60c01373ae7adfc7d0965a5e6d508fc5d8e69725cbd18ab8fbfbd20fc.jpg)  
Fig. 10 Qualitative comparison on held-out views of the NeRS MVMC dataset. The NeRS renders are those released by its authors, produced in the same fixed, optimized-camera setting as in table 7. NeRS sufers from distorted geometry, smeared texture, and residual viewpoint misalignment, while our renders remain sharp and pose-accurate. CADSim [42] is excluded because the authors did not include renders in their paper, and their code is not open source.

geometrically compatible shape instead (a bottle for the fire hydrant, a table for the PS5 controller) and the deformation field bridges the remaining category-level gap. The results demonstrate that our pipeline produces clean, artifact-free reconstructions from casual in-the-wild captures, even when the prior is only a rough geometric approximation of the imaged object rather than its actual design.

## 5 Applications

Because our method aligns the CAD model to the reconstruction and anchors every Gaussian to the CAD surface, the fitted asset inherits the CAD model’s structure, semantic information, and motion properties (if available). We illustrate two example applications enabled by this:

![](images/bafa8e5c1762831ffca2bd43c8929d335159a0ddf4ed0f7e4ad498e3df3d1070.jpg)  
Fig. 11 Qualitative evaluation on the NeRS Misc dataset. The input images are shown on the left, and the novel viewpoint renderings are shown on the right. The renders on NeRS [38] and CADNeRF [41] were reproduced from the NeRS dataset and the CADNeRF paper, where available.

Physically-based interaction. The CAD mesh serves as a collision proxy while the Gaussians provide photorealism. We drop a reconstructed hammer onto a reconstructed skateboard and run a rigid-body simulation on the two deformed CAD meshes. The interaction is resolved from the true object geometry and rendered photorealistically throughout (fig. 12).

Exploded views. Because the Gaussians are bound to CAD parts, the reconstruction inherits the CAD model’s part structure. Translating individual parts turns the photorealistic reconstruction into an exploded view: here the skateboard’s wheels slide of their axles while the deck stays fixed (fig. 13). This links the CAD model’s semantic, editable structure to the photorealistic appearance of the reconstruction. Both applications are shown animated across novel views in Online Resource 4.

![](images/ce899b8a8ef1262bafab299c86d43828691c18b323f09df4d43ea75eaff58294.jpg)  
(a) Hammer falling

![](images/6e30ce4db70f3d2eaf7cb65cd54cbe3204b2d53277b07855126bffbe95e8824b.jpg)  
(b) Just after first contact

![](images/72ac5c1a7e54c767bbe263a0985099813c3ba243f2063ab485a1d0969b2e3918.jpg)  
(c) At rest on the deck

Fig. 12 Physically-based interaction between two reconstructed assets. The CAD meshes act as collision geometry while the Gaussians provide appearance: a rigid-body simulation drops the reconstructed hammer onto the reconstructed skateboard, and the poses it produces are applied to the surface-anchored Gaussians, which follow rigidly. Contact is resolved from the true object geometry—not a bounding proxy—and rendered photorealistically.  
![](images/0dfb2c43be93d2c95868e042d1216149ead0a96ac7284468f047e7c5dddaed38.jpg)  
(a) Assembled

![](images/ab1688792847fff85c5a27aeb2f6658a4d4eb7b148ef70083f9fd33a2fca7c0e.jpg)  
(b) Exploded  
Fig. 13 Photorealistic exploded view. Because each Gaussian is anchored to a CAD part, translating individual parts of the CAD model carries their Gaussians along with them: the skateboard’s wheels slide of their axles while the deck stays fixed. The part structure comes from the CAD model; the appearance comes from the reconstruction.

## 6 Limitations

The method currently requires a good initial estimate of the relative calibration, whether from manual pre-calibration or SfM on the sparse views, both for silhouette matching to function properly and for the camera pose optimization to converge to a good minimum. The results are best when the CAD library contains a geometrically similar shape to the depicted object in the posed images. As the NeRS Misc experiments and sphere initialization experiments show, this is a loose requirement. Nevertheless, reconstruction quality in weakly observed or ambiguous regions benefits from a closer initial CAD match. Finally, the deformation field is optimized for reconstruction, not measurement: combined with the splats, it produces visually accurate renders, but the underlying deformed mesh is not itself optimized to be a plausible surface. We leave improving the surface quality of the deformed mesh toward metrology-grade measurement to future work.

Our method generalizes well to novel views near the capture trajectory. Extreme extrapolation, e.g., rendering a top-down view of a car observed only from the sides (fig. 14), yields unusable results, because the appearance model— per-splat opacities and view-dependent spherical harmonics—remains partly overfit to the training viewpoints. The SH-neighbor smoothness and splat-dropout regularizers of section 3.6.3 reduce this overfitting but do not remove it entirely. Extending the appearance model to generalize to such out-of-distribution viewpoints requires priors on object materials as well as their geometry.

![](images/e16dd71d7259f06f8f43032b44b1b106fcd492ea3e3b3e82be5485805ed4a21d.jpg)  
Fig. 14 Failure case: extreme-viewpoint extrapolation. The capture orbits the car at mid-height; rendered from directly overhead, far outside the observed viewing directions, the appearance breaks down, although the geometry stays on the CAD surface.

## 7 Conclusion

We presented CADSplat, a novel approach to reconstruct a photorealistic, geometrically clean digital twin from a handful of wide-baseline images by anchoring 3D Gaussians to a retrieved CAD model, registering the cameras to that model through silhouette consensus, and jointly refining the registration, a non-rigid deformation field, and the appearance. In our experiments, it outperforms unconstrained, few-shot, and meshtexturing baselines, and its quality degrades gracefully down to three views. We demonstrate that much of the rendering-quality improvement over unconstrained 3DGS comes from the constrained deformable representation. The CAD geometry prior matters most when the visual information in the images is ambiguous (e.g., extreme view sparsity or significant self-occlusion). Independently of rendering quality, the CAD prior yields camerato-object poses, which enables applications such as markerless augmented reality registration, perimage object pose estimation, physically based interaction, and part-aware editing. Improving the deformation field toward metrology-grade surface quality and extending the framework to extremeview synthesis are the main directions for future work.

Acknowledgements. This work was supported by the Flanders Make ADDIL project. We gratefully acknowledge imec IDLab for computational resources via the imec iLab.t infrastructure.

## References

[1] Mildenhall, B., Srinivasan, P.P., Tancik, M., Barron, J.T., Ramamoorthi, R., Ng, R.: Nerf: Representing scenes as neural radiance fields for view synthesis. Communications of the ACM 65(1), 99–106 (2021)

[2] Kerbl, B., Kopanas, G., Leimk¨uhler, T., Drettakis, G.: 3d gaussian splatting for real-time radiance field rendering. ACM Trans. Graph. 42(4), 139–1 (2023)

[3] Sarlin, P.-E., DeTone, D., Malisiewicz, T., Rabinovich, A.: Superglue: Learning feature matching with graph neural networks. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 4938–4948 (2020)

[4] Sarlin, P.-E., Cadena, C., Siegwart, R., Dymczyk, M.: From coarse to fine: Robust hierarchical localization at large scale. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 12716–12725 (2019)

[5] Chang, A.X., Funkhouser, T., Guibas, L., Hanrahan, P., Huang, Q., Li, Z., Savarese, S., Savva, M., Song, S., Su, H., et al.: Shapenet: An information-rich 3d model repository. arXiv preprint arXiv:1512.03012 (2015)

[6] Kwatra, A., Weinberg, T.M., Mandel, I., Batra, R., He, P., Guimbretiere, F., Roumen, T.: Splatoverflow: Asynchronous hardware troubleshooting. In: Proceedings of the 2025 CHI Conference on Human Factors in Computing Systems. CHI ’25. Association for Computing Machinery, New York, NY, USA (2025). https://doi.org/10.1145/3706598.3714129 https://doi.org/10.1145/3706598.3714129

[7] Zhu, Z., Fan, Z., Jiang, Y., Wang, Z.: Fsgs: Real-time few-shot view synthesis using gaussian splatting. In: European Conference on Computer Vision, pp. 145–163 (2024). Springer

[8] Li, J., Zhang, J., Bai, X., Zheng, J., Ning, X., Zhou, J., Gu, L.: Dngaussian: Optimizing sparse-view 3d gaussian radiance fields with global-local depth normalization. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 20775–20785 (2024)

[9] Deng, K., Liu, A., Zhu, J.-Y., Ramanan, D.: Depth-supervised nerf: Fewer views and faster training for free. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 12882–12891 (2022)

[10] Jain, A., Tancik, M., Abbeel, P.: Putting nerf on a diet: Semantically consistent fewshot view synthesis. In: Proceedings of the IEEE/CVF International Conference on Computer Vision, pp. 5885–5894 (2021)

[11] Chen, A., Xu, Z., Zhao, F., Zhang, X.,

Xiang, F., Yu, J., Su, H.: Mvsnerf: Fast generalizable radiance field reconstruction from multi-view stereo. In: Proceedings of the IEEE/CVF International Conference on Computer Vision, pp. 14124–14133 (2021)

[12] Yang, C., Li, S., Fang, J., Liang, R., Xie, L., Zhang, X., Shen, W., Tian, Q.: Gaussianobject: High-quality 3d object reconstruction from four views with gaussian splatting. ACM Transactions on Graphics (TOG) 43(6), 1–13 (2024)

[13] Wu, R., Mildenhall, B., Henzler, P., Park, K., Gao, R., Watson, D., Srinivasan, P.P., Verbin, D., Barron, J.T., Poole, B., Holynski, A.: Reconfusion: 3d reconstruction with difusion priors. arXiv (2023)

[14] Charatan, D., Li, S.L., Tagliasacchi, A., Sitzmann, V.: pixelsplat: 3d gaussian splats from image pairs for scalable generalizable 3d reconstruction. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 19457–19467 (2024)

[15] Chen, Y., Xu, H., Zheng, C., Zhuang, B., Pollefeys, M., Geiger, A., Cham, T.-J., Cai, J.: Mvsplat: Eficient 3d gaussian splatting from sparse multi-view images. In: European Conference on Computer Vision, pp. 370–386 (2024). Springer

[16] Szymanowicz, S., Rupprecht, C., Vedaldi, A.: Splatter image: Ultra-fast single-view 3d reconstruction. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 10208–10217 (2024)

[17] Mescheder, L., Dong, W., Li, S., Bai, X., Santos, M., Hu, P., Lecouat, B., Zhen, M., Delaunoy, A., Fang, T., Tsin, Y., Richter, S.R., Koltun, V.: Sharp monocular view synthesis in less than a second. arXiv preprint arXiv:2512.10685 (2025)

[18] Fan, Z., Cong, W., Wen, K., Wang, K., Zhang, J., Ding, X., Xu, D., Ivanovic, B., Pavone, M., Pavlakos, G., Wang, Z., Wang,

Y.: Instantsplat: Sparse-view sfm-free gaussian splatting in seconds. arXiv preprint arXiv:2403.20309 (2024)

[19] Waechter, M., Moehrle, N., Goesele, M.: Let there be color! — Large-scale texturing of 3D reconstructions. In: Proceedings of the European Conference on Computer Vision. Springer, ??? (2014)

[20] Gu´edon, A., Lepetit, V.: Sugar: Surfacealigned gaussian splatting for eficient 3d mesh reconstruction and high-quality mesh rendering. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 5354–5363 (2024)

[21] Waczy´nska, J., Borycki, P., Tadeja, S., Tabor, J., Spurek, P.: Games: Mesh-based adapting and modification of gaussian splatting. arXiv preprint arXiv:2402.01459 (2024)

[22] Qian, S., Kirschstein, T., Schoneveld, L., Davoli, D., Giebenhain, S., Nießner, M.: Gaussianavatars: Photorealistic head avatars with rigged 3d gaussians. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 20299– 20309 (2024)

[23] Park, K., Sinha, U., Barron, J.T., Bouaziz, S., Goldman, D.B., Seitz, S.M., Martin-Brualla, R.: Nerfies: Deformable neural radiance fields. In: Proceedings of the IEEE/CVF International Conference on Computer Vision, pp. 5865–5874 (2021)

[24] Yang, Z., Gao, X., Zhou, W., Jiao, S., Zhang, Y., Jin, X.: Deformable 3d gaussians for high-fidelity monocular dynamic scene reconstruction. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 20331–20341 (2024)

[25] Deng, Y., Yang, J., Tong, X.: Deformed implicit field: Modeling 3d shapes with learned dense correspondence. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 10286–10296 (2021)

[26] Sch¨onberger, J.L., Frahm, J.-M.: Structurefrom-motion revisited. In: Conference on Computer Vision and Pattern Recognition (CVPR) (2016)

[27] Drummond, T., Cipolla, R.: Real-time visual tracking of complex structures. IEEE Transactions on pattern analysis and machine intelligence 24(7), 932–946 (2002)

[28] Wang, H., Sridhar, S., Huang, J., Valentin, J., Song, S., Guibas, L.J.: Normalized object coordinate space for category-level 6d object pose and size estimation. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 2642– 2651 (2019)

[29] Avetisyan, A., Dahnert, M., Dai, A., Savva, M., Chang, A.X., Nießner, M.: Scan2cad: Learning cad model alignment in rgb-d scans. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 2614–2623 (2019)

[30] Kuo, W., Angelova, A., Lin, T.-Y., Dai, A.: Mask2cad: 3d shape prediction by learning to segment and retrieve. In: European Conference on Computer Vision, pp. 260–277 (2020). Springer

[31] G¨umeli, C., Dai, A., Nießner, M.: Roca: Robust cad model retrieval and alignment from a single image. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 4022– 4031 (2022)

[32] Langer, F., Budvytis, I., Cipolla, R.: Sparc: Sparse render-and-compare for cad model alignment in a single rgb image. In: Proceedings of the British Machine Vision Conference (BMVC) (2022)

[33] Gao, D., Rozenberszki, D., Leutenegger, S., Dai, A.: Difcad: Weakly-supervised probabilistic cad model retrieval and alignment from an rgb image. ACM Transactions on Graphics (TOG) 43(4) (2024)

[34] Yen-Chen, L., Florence, P., Barron, J.T., Rodriguez, A., Isola, P., Lin, T.-Y.: inerf:

Inverting neural radiance fields for pose estimation. In: 2021 IEEE/RSJ International Conference on Intelligent Robots and Systems (IROS), pp. 1323–1330 (2021). IEEE

[35] Lin, C.-H., Ma, W.-C., Torralba, A., Lucey, S.: Barf: Bundle-adjusting neural radiance fields. In: Proceedings of the IEEE/CVF International Conference on Computer Vision, pp. 5741–5751 (2021)

[36] Bian, W., Wang, Z., Li, K., Bian, J.-W., Prisacariu, V.A.: Nope-nerf: Optimising neural radiance field with no pose prior. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 4160–4169 (2023)

[37] Fu, Y., Liu, S., Kulkarni, A., Kautz, J., Efros, A.A., Wang, X.: Colmap-free 3d gaussian splatting. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 20796–20805 (2024)

[38] Zhang, J., Yang, G., Tulsiani, S., Ramanan, D.: Ners: Neural reflectance surfaces for sparse-view 3d reconstruction in the wild. Advances in Neural Information Processing Systems 34, 29835–29847 (2021)

[39] Vicini, D., Speierer, S., Jakob, W.: Diferentiable signed distance function rendering. ACM Transactions on Graphics (ToG) 41(4), 1–18 (2022)

[40] Wang, P., Liu, L., Liu, Y., Theobalt, C., Komura, T., Wang, W.: Neus: Learning neural implicit surfaces by volume rendering for multi-view reconstruction. arXiv preprint arXiv:2106.10689 (2021)

[41] Wen, X., Zhu, X., Yi, R., Wang, Z., Zhu, C., Xu, K.: Cad-nerf: learning nerfs from uncalibrated few-view images by cad model retrieval. Frontiers of Computer Science 19(10), 1910706 (2025)

[42] Wang, J., Manivasagam, S., Chen, Y., Yang, Z., Bˆarsan, I.A., Yang, A.J., Ma, W.-C., Urtasun, R.: Cadsim: Robust and scalable in-the-wild 3d reconstruction for controllable sensor simulation. In: Proceedings of The 6th

Conference on Robot Learning. Proceedings of Machine Learning Research, vol. 205, pp. 630–642. PMLR, ??? (2023)

[43] Carion, N., Gustafson, L., Hu, Y.-T., Debnath, S., Hu, R., Suris, D., Ryali, C., Alwala, K.V., Khedr, H., Huang, A., Lei, J., Ma, T., Guo, B., Kalla, A., Marks, M., Greer, J., Wang, M., Sun, P., R¨adle, R., Afouras, T., Mavroudi, E., Xu, K., Wu, T.-H., Zhou, Y., Momeni, L., Hazra, R., Ding, S., Vaze, S., Porcher, F., Li, F., Li, S., Kamath, A., Cheng, H.K., Doll´ar, P., Ravi, N., Saenko, K., Zhang, P., Feichtenhofer, C.: SAM 3: Segment Anything with Concepts (2025). https: //arxiv.org/abs/2511.16719

[44] Zhou, Y., Barnes, C., Lu, J., Yang, J., Li, H.: On the continuity of rotation representations in neural networks. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 5745– 5753 (2019)

[45] Lowe, D.G.: Distinctive image features from scale-invariant keypoints. International journal of computer vision 60(2), 91–110 (2004)

[46] Umeyama, S.: Least-squares estimation of transformation parameters between two point patterns. IEEE Transactions on pattern analysis and machine intelligence 13(4), 376–380 (1991)

[47] Wang, Z., Bovik, A.C., Sheikh, H.R., Simoncelli, E.P.: Image quality assessment: from error visibility to structural similarity. IEEE Transactions on Image Processing 13(4), 600–612 (2004)

[48] Zhang, R., Isola, P., Efros, A.A., Shechtman, E., Wang, O.: The unreasonable efectiveness of deep features as a perceptual metric. In: Proceedings of the IEEE Conference on Computer Vision and Pattern Recognition (CVPR), pp. 586–595 (2018)

[49] Andersson, P., Nilsson, J., Akenine-M¨oller, T., Oskarsson, M., <sup>˚</sup>Astr¨om, K., Fairchild, M.D.: Flip: A diference evaluator for alternating images. Proceedings of the ACM on

Computer Graphics and Interactive Techniques 3(2), 15–11523 (2020)

[50] Yu, A., Ye, V., Tancik, M., Kanazawa, A.: pixelnerf: Neural radiance fields from one or few images. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 4578– 4587 (2021)

[51] Niemeyer, M., Barron, J.T., Mildenhall, B., Sajjadi, M.S., Geiger, A., Radwan, N.: Regnerf: Regularizing neural radiance fields for view synthesis from sparse inputs. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 5480–5490 (2022)

[52] Reizenstein, J., Shapovalov, R., Henzler, P., Sbordone, L., Labatut, P., Novotny, D.: Common objects in 3d: Large-scale learning and evaluation of real-life 3d category reconstruction. In: Proceedings of the IEEE/CVF International Conference on Computer Vision (ICCV), pp. 10901–10911 (2021)

[53] Wang, J., Chen, M., Karaev, N., Vedaldi, A., Rupprecht, C., Novotny, D.: Vggt: Visual geometry grounded transformer. In: Proceedings of the Computer Vision and Pattern Recognition Conference, pp. 5294–5306 (2025)