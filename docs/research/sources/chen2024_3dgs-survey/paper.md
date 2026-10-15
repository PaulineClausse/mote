<!-- page 1 of 41 -->

arXiv:2401.03890v9 [cs.CV] 9 Apr 2026

# A Survey on 3D Gaussian Splatting

GUIKUN CHEN, The State Key Lab of Brain-Machine Intelligence, Zhejiang University, China

WENGUAN WANG<sup>∗</sup>, The State Key Lab of Brain-Machine Intelligence, Zhejiang University, China

3D Gaussian splatting (GS) has emerged as a transformative technique in radiance fields. Unlike mainstream implicit neural models, 3D GS uses millions of learnable 3D Gaussians for an explicit scene representation. Paired with a differentiable rendering algorithm, this approach achieves real-time rendering and unprecedented editability, making it a potential game-changer for 3D reconstruction and representation. In the present paper, we provide the first systematic overview of the recent developments and critical contributions in 3D GS. We begin with a detailed exploration of the underlying principles and the driving forces behind the emergence of 3D GS laying the groundwork for understanding its significance. A focal point of our discussion is the practical applicability of 3D GS. By enabling unprecedented rendering speed, 3D GS opens up a plethora of applications, ranging from virtual reality to interactive media and beyond. This is complemented by a comparative analysis of leading 3D GS models, evaluated across various benchmark tasks to highlight their performance and practical utility. The survey concludes by identifying current challenges and suggesting potential avenues for future research. Through this survey, we aim to provide a valuable resource for both newcomers and seasoned researchers, fostering further exploration and advancement in explicit radiance field.

CCS Concepts: • **General and reference** → **Surveys and overviews**; • **Computing methodologies** → **Rendering**; **Computer vision**.

Additional Key Words and Phrases: 3D Gaussian Splatting, Explicit Radiance Field

## ACM Reference Format:

Guikun Chen and Wenguan Wang. 2026. A Survey on 3D Gaussian Splatting. 1, 1 (April 2026), 41 pages. [https://doi.org/10.1145/nnnnnnn.nnnnnnn](https://doi.org/10.1145/nnnnnnn.nnnnnnn)

## 1 INTRODUCTION

The objective of image based 3D scene reconstruction is to convert a collection of views capturing a scene into a digital 3D model that can be computationally processed, analyzed, and manipulated. This hard and long-standing problem is fundamental for machines to comprehend real-world environments, facilitating a wide array of applications such as 3D modeling and animation, robot navigation, historical preservation, augmented/virtual reality, and autonomous driving.

The journey of 3D scene reconstruction began long before the surge of deep learning, with early endeavors focusing on light fields and basic reconstruction methods [18, 68, 128]. These early attempts, however, were limited by their reliance on dense sampling and structured capture, leading to challenges in handling complex scenes and lighting conditions. The emergence of structure-from-motion [230] and subsequent advancements in multi-view stereo [67] algorithms provided a more robust framework. Despite these advancements, such methods struggled with novel-view

<small><span class="docvortex-page-footnote" data-block-type="page_footnote" style="color:#6b7280"><sup>∗</sup>Corresponding author</span></small>

<small><span class="docvortex-page-footnote" data-block-type="page_footnote" style="color:#6b7280">Authors’ addresses: Guikun Chen, The State Key Lab of Brain-Machine Intelligence, Zhejiang University, Hangzhou, China, guikunchen@gmail.com; Wenguan Wang, The State Key Lab of Brain-Machine Intelligence, Zhejiang University, Hangzhou, China, wenguanwang.ai@gmail.com.</span></small>

Permission to make digital or hard copies of all or part of this work for personal or classroom use is granted without fee provided that copies are not made or distributed for profit or commercial advantage and that copies bear this notice and the full citation on the first page. Copyrights for components of this work owned by others than ACM must be honored. Abstracting with credit is permitted. To copy otherwise, or republish, to post on servers or to redistribute to lists, requires prior specific permission and/or a fee. Request permissions from permissions@acm.org.

Manuscript submitted to ACM

1

<!-- page 2 of 41 -->

2

Guikun Chen and Wenguan Wang

synthesis and texture loss. NeRF represents a quantum leap in this progression. By leveraging neural networks, NeRF enabled the direct mapping of spatial coordinates to color and density. The success of NeRF hinged on its ability to create continuous, volumetric scene functions, producing results with unprecedented fidelity. However, as with any burgeoning technology, it came at a cost: i) Computational Intensity. NeRF based methods are computationally intensive [64, 181], often requiring substantial training times and resources for rendering, especially for high-resolution outputs. **ii**) Editability. Manipulating scenes represented implicitly is challenging, since direct modifications to the neural network’s weights are not intuitively related to changes in geometric or appearance properties of the scene.

It is in this context that 3D Gaussian splatting (GS) [111] emerges, not merely as an incremental improvement but as a paradigm-shifting approach that redefines the boundaries of scene representation and rendering. While NeRF excelled in creating photorealistic images, the need for faster, more efficient rendering methods was becoming increasingly apparent, especially for applications (e.g., virtual reality and autonomous driving) that are highly sensitive to latency. 3D GS addressed this need by introducing an advanced, explicit scene representation that models a scene using millions of learnable 3D Gaussians in space. Unlike the implicit, coordinate-based models [174, 228], 3D GS employs an explicit representation and highly parallelized workflows, facilitating more efficient computation and rendering. The innovation of 3D GS lies in its unique blend of the benefits of differentiable pipelines and pointbased rendering techniques [197, 210, 297, 349]. By representing scenes with learnable 3D Gaussians, it preserves the strong fitting capability of continuous volumetric radiance fields, essential for high-quality image synthesis, while simultaneously avoiding the computational overhead associated with NeRF based methods (e.g., computationally expensive ray-marching, and unnecessary calculations in empty space).

The introduction of 3D GS is not just a technical advancement; it represents a fundamental shift in how we approach scene representation and rendering in computer vision and graphics. By enabling real-time rendering capabilities without compromising on visual quality, 3D GS opens up a plethora of possibilities for applications ranging from virtual reality and augmented reality to real-time cinematic rendering and beyond [4, 103, 107, 192]. This technology holds the promise of not only enhancing existing applications but also enabling new ones that were previously unfeasible due to computational constraints. Furthermore, 3D GS’s explicit scene representation offers unprecedented flexibility to control the objects and scene dynamics, a crucial factor in complex scenarios involving intricate geometries and varying lighting conditions [160, 214, 320]. This level of editability, combined with the efficiency of the training and rendering process, positions 3D GS as a transformative force in shaping future developments in relevant fields.

In an effort to assist readers in keeping pace with the swift evolution of 3D GS, we provide the first survey on 3D GS, which presents a systematic and timely collection of the most significant literature on the topic. Given that GS is a very recent innovation (c.f . Fig. S1), this survey focuses in particular on its principles, and the diverse developments and contributions that have emerged since its introduction. We systematically review the foundational period of GS, with selected works primarily sourced from top-tier conferences. Our analysis concentrates on the initial explosion of research following its introduction in 2023 through 2024, covering the theoretical underpinnings, landmark developments, and early applications that shaped the field. Acknowledging the nascent yet rapidly evolving nature, this survey is inevitably a biased view, but we strive to offer a balanced perspective that reflects both the current state and the future potential of this field. Our aim is to encapsulate the primary research trends and serve as a valuable resource for both researchers and practitioners eager to understand and contribute to this rapidly evolving domain. The distinctions of this paper from existing surveys (general [11, 41, 52, 267] or domain-specific [5, 10, 75]) are evident in the following aspects: • We provide the first systematic and comprehensive review that examines 3D GS from a macro-level perspective by establishing clear taxonomies and frameworks. This high-level systematization helps researchers identify trends and Manuscript submitted to ACM

<!-- page 3 of 41 -->

A Survey on 3D Gaussian Splatting

3

potential directions that might not be apparent from paper-specific reviews. Our organizational structure serves as a roadmap for understanding how different approaches relate to and build upon each other within the 3D GS ecosystem. • This paper is the first and only survey to thoroughly delve into the theoretical background and fundamental principles of 3D GS. The comprehensive coverage makes the field more approachable for newcomers while providing valuable insights for experienced researchers.

• To ensure our survey remains relevant and offer long-term value in this rapidly evolving field, we maintain two dynamic GitHub repositories: [one](https://github.com/guikunchen/Awesome3DGS) that follows our survey’s organizational structure and [another](https://github.com/guikunchen/3DGS-Benchmarks) that includes comprehensive performance comparisons with analysis data.

A summary of the structure of this article can be found in Fig. 1, which is presented as follows: Sec. 2 provides a brief background on problem formulation, terminology, and related research domains. Sec. 3 introduces the essential insights of 3D GS, encompassing the rendering process with learned 3D Gaussians and the optimization details (i.e., how to learn 3D Gaussians) of 3D GS. Sec. 4 presents several fruitful directions that aim to improve the capabilities of the original 3D GS. Sec. 5 unveils the diverse application areas and tasks where 3D GS has made significant impacts, showcasing its versatility. Sec. 6 conducts performance comparison and analysis. Finally, Sec. 7 and 8 highlight the open questions for further research and conclude the survey.

## 2 BACKGROUND

This section provides a brief formulation of radiance fields (Sec. 2.1), including both implicit and explicit ones. Sec. 2.2 further establishes linkages with relevant rendering algorithms and terminologies. Please see [74, 115, 245, 256, 273] for a comprehensive overview of radiance fields, scene reconstruction and representation, and rendering methods.

## 2.1 Radiance Field

• **Implicit Radiance Field.** An implicit radiance field represents light distribution in a scene without explicitly defining the geometry of the scene. In the deep learning era, neural networks are often used to learn a continuous volumetric scene representation [172, 189]. The most prominent example is NeRF [174]. In NeRF (Fig. S2a), one or more MLPs are used to map a set of spatial coordinates (𝑥, 𝑦, 𝑧) and viewing directions (𝜃, 𝜙) to color 𝑐 and volume density 𝜎:

$$
(c, \sigma) \leftarrow \operatorname{MLP} (x, y, z, \theta , \phi).\tag{1}
$$

This format allows for a differentiable and compact representation of scenes, albeit often at the cost of high computational load. Note that typically, the color 𝑐 is direction-dependent, whereas the volume density 𝜎 is not [174].

• **Explicit Radiance Field.** An explicit radiance field directly represents the distribution of light in a discrete spatial structure, such as a voxel grid or a set of points [57, 236]. Each element in this structure stores the radiance information for its respective location. This allows for direct and often faster access to radiance data but at the cost of higher memory usage and potentially lower resolution. Plenoxels [58] highlighted this trend by discarding the MLP and directly optimizing a sparse voxel grid with spherical harmonic coefficients, showing that a fully explicit grid can achieve NeRF-level quality while converging much faster. Similar to the implicit radiance field, the explicit one is written as:

$$
(c, \sigma) \leftarrow \text {DataStructure} (x, y, z, \theta , \phi),\tag{2}
$$

where DataStructure could be in the format of volumes, point clouds, etc. DataStructure encodes directional color in two main ways. One is encoding high-dimensional features that are subsequently decoded by a lightweight MLP. Another

<!-- page 4 of 41 -->

4

Guikun Chen and Wenguan Wang

![Image block](images/chen2024_3dgs-survey_p4_b3.png)

Fig. 1. Structure of the overall review.

one is directly storing coefficients of directional basis functions, such as spherical harmonics or spherical Gaussians, where the final color is computed as a function of these coefficients and the viewing direction.

• **3D Gaussian Splatting: Best-of-Both Worlds.** 3D GS [111] is an explicit radiance field with the advantages of implicit radiance fields. Concretely, it uses the strengths of both paradigms by utilizing learnable 3D Gaussians as the basis elements of DataStructure. Note that 3D GS encodes the opacity 𝛼 directly for each Gaussian, as opposed to approaches of first establishing density 𝜎 and then computing opacity based on that density. As in previous reconstruction work, 3D Gaussians are optimized under the supervision of multi-view images to represent the scene. Such a 3D Gaussian based differentiable pipeline combines the benefits of neural network based optimization and explicit, structured data storage. This hybrid approach aims to achieve real-time, high-quality rendering and requires less training time, particularly for complex scenes and high-resolution outputs. In addition, from a differentiable rendering perspective, 3D GS complements mesh-based differentiable rasterizers such as nvdiffrast [119], which operate on explicit triangle meshes using high-performance modular rasterization primitives.

## 2.2 Context and Terminology

• **Volumetric rendering** aims to transform a 3D volumetric representation into an image by integrating radiance along camera rays. A camera ray 𝒓(𝑡) can be parameterized as: $\boldsymbol { r } ( t ) = \boldsymbol { o } + t \boldsymbol { d } , t \in [ t _ { \mathrm { n e a r } } , t _ { \mathrm { f a r } } ] ,$ , where 𝒐 represents the ray Manuscript submitted to ACM

<!-- page 5 of 41 -->

A Survey on 3D Gaussian Splatting

5

origin (camera center), 𝒅 is the ray direction, and 𝑡 indicates the distance along the ray between near and far clipping planes. The pixel color 𝐶(𝒓) is computed through a line integral along the ray $r ( t )$ , mathematically expressed as [174]:

$$
C (\boldsymbol {r}) = \int_ {t _ {\text {near}}} ^ {t _ {\text {far}}} T (t) \sigma (\boldsymbol {r} (t)) c (\boldsymbol {r} (t), \boldsymbol {d}) d t,\tag{3}
$$

where $\sigma ( r ( t ) )$ is the volume density at point $\boldsymbol{r}(t),c(\boldsymbol{r}(t),\boldsymbol{d})$ is the color at that point, and $T ( t )$ is the transmittance. Ray marching directly approximates the volumetric rendering integral by systematically “stepping” along a ray and sampling the scene’s properties at discrete intervals. NeRF [174] shares the same spirit of ray-marching and introduces importance sampling and positional encoding to improve the quality of synthesized images. While providing high-quality results, ray-marching is computationally expensive, especially for high-resolution images.

• **Point-based rendering** represents another class of rendering algorithms, of which 3D GS introduces a notable implementation. Its simplest form [69] rasterizes point clouds with a fixed size, which introduces drawbacks such as holes and rendering artifacts. Seminal works addressed these limitations through various methods, including: i) employing multi-resolution level-of-detail hierarchies like QSplat [213] to handle large-scale scenes, **ii**) splatting point primitives with a spatial extent [210, 348–350], and **iii**) more recently, embedding neural features directly into points for subsequent network-based rendering [6, 212]. 3D GS uses 3D Gaussian as the point primitive that contains explicit attributes (e.g., color and opacity) instead of implicit neural features. The rendering approach, i.e., point-based 𝛼-blending (exemplified in Eq. 5), shares the same image formation model as NeRF-style volumetric rendering (Eq. 3) [111], but demonstrates substantial speed advantages. This advantage originates from fundamental algorithmic differences. NeRFs approximate a line integral along a ray for each pixel, requiring expensive sampling. Point-based methods render point clouds using rasterization, which inherently benefits from parallel computational strategies [122].

## 3 3D GAUSSIAN SPLATTING: PRINCIPLES

3D GS offers a breakthrough in real-time, high-resolution image rendering, without relying on deep neural networks. This section aims to provide essential insights of 3D GS. We first elaborate on how 3D GS synthesizes an image given well-constructed 3D Gaussians in Sec. 3.1, i.e., the forward process of 3D GS. Then, we introduce how to obtain well-constructed 3D Gaussians for a given scene in Sec. 3.2, i.e., the optimization process of 3D GS.

## 3.1 Rendering with Learned 3D Gaussians

Consider a scene represented by optimized 3D Gaussians. The objective is to generate an image from a specified camera pose. Recall that NeRFs approach this task through volumetric ray-marching, sampling 3D space points per pixel. Such a paradigm struggles with high-resolution image synthesis, failing to achieve real-time rendering, especially for platforms with limited computing resources [111]. By contrast, 3D GS begins by projecting these 3D Gaussians onto a pixel-based image plane, a process termed “splatting” [348, 350] (c.f . Fig. S2b). Afterwards, 3D GS sorts these Gaussians and computes the value for each pixel. As shown in Fig. S2, the rendering of NeRFs and 3D GS can be viewed as an inverse process of each other. In what follows, we begin with the definition of a 3D Gaussian, which is the minimal element of the scene representation in 3D GS. Next, we describe how these 3D Gaussians can be used for differentiable rendering. Finally, we introduce the acceleration technique used in 3D GS, which is the key to fast rendering.

• **Properties of 3D Gaussian.** A 3D Gaussian is characterized by its center 𝝁, opacity 𝛼, 3D covariance matrix $\Sigma ,$ and color 𝑐. 𝑐 is represented by spherical harmonics (SH) coefficients to model view-dependent appearance. Unlike a static RGB value, SH functions allow the color to vary based on the viewing angle. This enables the representation to capture

Manuscript submitted to ACM

<!-- page 6 of 41 -->

6

Guikun Chen and Wenguan Wang

![Image block](images/chen2024_3dgs-survey_p6_b3.png)

Fig. 2. An illustration of the forward process of 3D GS (see Sec. 3.1). (a) The splatting step projects 3D Gaussians into image space. (b) 3D GS divides the image into multiple non-overlapping patches, i.e., tiles. (c) 3D GS replicates the Gaussians which cover several tiles, assigning each copy an identifier, i.e., a tile ID. (d) By rendering the sorted Gaussians, we can obtain all pixels within the tile. Note that the computational workflows for pixels and tiles are independent and can be done in parallel. Best viewed in color.

non-Lambertian effects, such as specular highlights and lighting variations, by evaluating the SH coefficients with the specific view direction during rendering. All the properties are learnable and optimized through back-propagation.

• **Frustum Culling.** Given a specified camera pose, this step determines which 3D Gaussians are outside the camera’s frustum. By doing so, 3D Gaussians outside the given view will not be involved in the subsequent computation.

• **Splatting** (Fig. 2a). In this step, 3D Gaussians (ellipsoids) in 3D space are projected into 2D image space (ellipses). The projection proceeds through two transformations: first, transforming 3D Gaussians from world coordinates to camera coordinates using viewing transformation, and subsequently splatting these Gaussians into 2D image space via an approximation of projective transformation. Given the 3D covariance matrix 𝚺 describing a 3D Gaussian and viewing transformation matrix 𝑾, the 2D covariance matrix $\Sigma ^ { \prime }$ characterizing the projected 2D Gaussian is computed through:

$$
\Sigma^ {\prime} = J W \Sigma W ^ {\top} J ^ {\top},\tag{4}
$$

where 𝑱 is the Jacobian of the affine approximation of the projective transformation [111, 348]. One might wonder why the standard camera intrinsics based projective transformation is not used here. This is because its mappings are not affine and therefore cannot directly project 𝚺. 3D GS adopts an affine one proposed in [348] which approximates the projective transformation using the first two terms (including 𝑱) of the Taylor expansion (see Sec. 4.4 in [348]).

• **Rendering by Pixels.** Before delving into the final version of GS with highly parallel computation, we first elaborate on its simpler form to offer insights into its basic working mechanism. Given the position of a pixel 𝒙, its distance to all overlapping Gaussians, i.e., the depths of these Gaussians, can be computed through the viewing transformation matrix 𝑾, forming a sorted list of Gaussians N. Then, 𝛼-blending [198] is adopted to compute the final color of this pixel:

$$
C = \sum_ {n = 1} ^ {| \mathcal {N} |} c _ {n} \alpha_ {n} ^ {\prime} \prod_ {j = 1} ^ {n - 1} \left(1 - \alpha_ {j} ^ {\prime}\right),\tag{5}
$$

where $c _ { n }$ is the learned color. The final opacity $\alpha _ { n } ^ { \prime }$ is the multiplication result of the learned opacity $\alpha _ { n }$ and the Gaussian:

$$
\alpha_ {n} ^ {\prime} = \alpha_ {n} \times \exp \big (- 0. 5 (\boldsymbol {x} ^ {\prime} - \boldsymbol {\mu} _ {n} ^ {\prime}) ^ {\top} \Sigma_ {n} ^ {- 1} (\boldsymbol {x} ^ {\prime} - \boldsymbol {\mu} _ {n} ^ {\prime}) \big),\tag{6}
$$

where $x ^ { \prime }$ and $\mu _ { n } ^ { \prime }$ are coordinates in the projected space. It is a reasonable concern that the rendering process described could be slower compared to NeRFs, given that generating the required sorted list is hard to parallelize. Indeed, this concern is justified; rendering speeds can be significantly impacted when utilizing such a simplistic, pixel-by-pixel approach. To achieve real-time rendering, 3D GS makes several concessions to accommodate parallel computation. Manuscript submitted to ACM

<!-- page 7 of 41 -->

A Survey on 3D Gaussian Splatting

7

• **Tiles (Patches).** To avoid the cost computation of deriving Gaussians for each pixel, 3D GS shifts the precision from pixel-level to patch-level detail, which is inspired by tile-based rasterization [122]. Concretely, 3D GS initially divides the image into multiple non-overlapping patches (tiles). Fig. 2b provides an illustration of tiles. Each tile comprises 16×16 pixels as suggested in [111]. 3D GS further determines which **tiles** intersect with these projected Gaussians. Given that a projected Gaussian may cover several tiles, a logical method involves replicating the Gaussian, assigning each copy an identifier (i.e., a tile ID) for the relevant tile.

• **Parallel Rendering.** After replication, 3D GS combines the respective tile ID with the depth value obtained from the view transformation for each Gaussian. This results in an unsorted list of bytes where the upper bits represent the tile ID and the lower bits signify depth. By doing so, the sorted list can be directly utilized for rendering (i.e., alpha compositing). Fig. 2c and Fig. 2d provide the visual demonstration of such concepts. It’s worth highlighting that rendering each tile and pixel occurs **independently**, making this process highly suitable for parallel computations. An additional benefit is that each tile’s pixels can access a common **shared memory** and maintain an **uniform read sequence** (Fig. S3), enabling parallel execution of alpha compositing with increased efficiency. In the official implementation of the original paper [111], the framework regards the processing of tiles and pixels as analogous to the blocks and threads, respectively, in CUDA programming architecture.

## 3.2 Optimization of 3D Gaussian Splatting

At the heart of 3D GS lies an optimization procedure devised to construct a copious collection of 3D Gaussians that accurately captures the scene’s essence, thereby facilitating free-viewpoint rendering. On the one hand, the properties of 3D Gaussians should be optimized via differentiable rasterization to fit the textures of a given scene. On the other hand, the number of 3D Gaussians that can represent a given scene well is unknown in advance. We will introduce how to optimize the properties of each Gaussian in Sec. 3.2.1 and how to adaptively control the density of the Gaussians in Sec. 3.2.2. The two procedures are interleaved within the optimization workflow. Since there are many manually set hyperparameters in the optimization process, we omit the notations of most hyperparameters for clarity.

3.2.1 Parameter Optimization. • **Loss Function.** Once the synthesis of the image is completed, the difference between the rendered image and ground truth can be measured. All the learnable parameters are optimized by stochastic gradient descent using the ℓ<sub>1</sub> and D-SSIM loss functions:

$$
\mathcal {L} = (1 - \lambda) \mathcal {L} _ {1} + \lambda \mathcal {L} _ {\mathrm{D-SSIM}},\tag{7}
$$

where $\lambda \in [ 0 , 1 ]$ is a weighting factor. Here, L<sub>D</sub>-<sub>S</sub>SIM is formulated as 1 − SSIM, derived from the structural similarity index measure (SSIM). While $\mathcal { L } _ { 1 }$ minimizes absolute pixel-wise differences, L<sub>D</sub>-<sub>S</sub>SIM acts as a perceptual metric that enforces structural consistency, ensuring that the synthesized images preserve high-frequency details and local luminance patterns often missed by ℓ<sub>1</sub> alone.

• **Parameter Update.** Most properties of a 3D Gaussian can be optimized directly through back-propagation. It is essential to note that directly optimizing the covariance matrix 𝚺 can result in a non-positive semi-definite matrix, which would not adhere to the physical interpretation typically associated with covariance matrices. To circumvent this issue, 3D GS chooses to optimize a quaternion 𝒒 and a 3D vector 𝒔. Here 𝒒 and 𝒔 represent rotation and scale, respectively. This approach allows the covariance matrix 𝚺 to be reconstructed as follows:

$$
\Sigma = R S S ^ {\top} R ^ {\top},\tag{8}
$$

Manuscript submitted to ACM

<!-- page 8 of 41 -->

8

Guikun Chen and Wenguan Wang

where 𝑹 is the rotation matrix derived from the quaternion 𝒒, and 𝑺 is the scaling matrix given by diag(𝒔). As seen, there is a complex computational graph to obtain the opacity 𝛼, i.e., 𝒒 and ${ \mathfrak { s } } \mapsto \Sigma , \Sigma \mapsto \Sigma ^ { \prime }$ , and $\Sigma ^ { \prime } \mapsto \alpha .$ To avoid the cost of automatic differentiation, 3D GS derives the gradients for 𝒒 and 𝒔 to compute them directly during optimization.

3.2.2 Density Control. • **Initialization.** 3D GS starts with the initial set of sparse points from SfM or random initialization. Note that a good initialization is essential to convergence and reconstruction quality [34]. Afterwards, point densification and pruning are adopted to control the density of 3D Gaussians.

• **Point Densification.** In the point densification phase, 3D GS adaptively increases the density of Gaussians to better capture the details of a scene. This process focuses on areas with missing geometric features or regions where Gaussians are too spread out. The densification procedure will be performed at regular intervals (i.e., after a certain number of training iterations), focusing on those Gaussians with large view-space positional gradients (i.e., above a specific threshold). It involves either cloning small Gaussians in under-reconstructed areas or splitting large Gaussians in over-reconstructed regions. For cloning, a copy of the Gaussian is created and moved towards the positional gradient. For splitting, a large Gaussian is replaced with two smaller ones, reducing their scale by a specific factor. This step seeks an optimal distribution and representation of Gaussians in 3D space, enhancing the overall quality of the reconstruction • **Point Pruning.** The point pruning stage involves the removal of superfluous or less impactful Gaussians, which can be viewed as a regularization process. It is executed by eliminating Gaussians that are virtually transparent (with 𝛼 below a specified threshold) and those that are excessively large in either world-space or view-space. In addition, to prevent unjustified increases in Gaussian density near input cameras, the alpha value of the Gaussians is set close to zero after a certain number of iterations. This allows for a controlled increase in the density of necessary Gaussians while enabling the culling of redundant ones. The process not only helps in conserving computational resources but also ensures that the Gaussians in the model remain precise and effective for the representation of the scene.

## 4 3D GAUSSIAN SPLATTING: DIRECTIONS

Though 3D GS has achieved impressive milestones, significant room for improvement remains, e.g., data and hardware requirement, rendering and optimization algorithm, and applications in downstream tasks. In the subsequent sections, we seek to elaborate on select extended versions. These are: i) 3D GS for Sparse Input (Sec. 4.1), **ii**) Memory-efficient 3D GS (Sec. 4.2), **iii**) Photorealistic 3D GS (Sec. 4.3), **iv**) Improved Optimization Algorithms (Sec. 4.4), v) 3D Gaussian with More Properties (Sec. 4.5), **vi**) Hybrid Representation (Sec. 4.6), and **vii**) New Rendering Algorithm (Sec. 4.7). To provide a synthesized overview before delving into each direction, Table S1 summarizes their key ideas, representative works (ordered chronologically), advantages, and limitations. While we have carefully selected several key directions, we acknowledge that it is inevitably a biased view. A more comprehensive collection is given in [Github.](https://github.com/guikunchen/Awesome3DGS)

## 4.1 3D GS for Sparse Input

A notable issue of 3D GS is the emergence of artifacts in areas with insufficient observational data. This challenge is a prevalent limitation in radiance field rendering, where sparse data often leads to inaccuracies in reconstruction. From a practical perspective, reconstructing scenes from limited viewpoints is of significant interest, particularly for the potential to enhance functionality with minimal input.

Existing methods can be categorized into two groups (cf. Table S2). **i) Regularization** based methods introduce additional constraints such as depth information to enhance the detail and global consistency [32, 133, 312, 340]. For example, DNGaussian [133] introduced a depth-regularized scheme to address the challenge of geometry degradation. FSGS [340] Manuscript submitted to ACM

<!-- page 9 of 41 -->

A Survey on 3D Gaussian Splatting

9

devised a Gaussian Unpooling process for initialization and also introduced depth regularization. MVSplat [32] proposed a cost volume representation so as to provide geometry cues. Unfortunately, when dealing with a limited number of views, or even just one, the efficacy of regularization techniques tends to diminish, which leads to **ii) generalizability** based methods that use learned priors [26, 240, 241, 278]. One approach involves synthesizing additional views through generative models, which can be seamlessly integrated into existing reconstruction pipelines [217]. However, this augmentation strategy is computationally intensive and inherently bounded by the capabilities of the used generative model. Another well-known paradigm employs feed-forward Gaussian model to directly generates the properties of a set of 3D Gaussians. This paradigm typically requires multiple views for training but can reconstruct 3D scenes with only one input image. For instance, PixelSplat [26] proposed to sample Gaussians from dense probability distributions. Splatter Image [241] introduced a 2D image-to-image network that maps an input image to a 3D Gaussian per pixel. However, as the generated pixel-aligned Gaussians are distributed nearly evenly in the space, they struggle to represent high-frequency details and smoother regions with an appropriate number of Gaussians

The challenge of 3DGS for sparse inputs centers on how priors are modeled, whether through depth information, generative models, or feed-forward Gaussian models. In practice, there is a trade-off between regularization-based methods, which rely on strong constraints and per-scene optimization (favoring geometric quality but incurring higher computation), and generalizability-based methods, which use learned priors for fast feed-forward inference (favoring speed and cross-scene generalization, but sometimes at the expense of geometric fidelity). We summarize these characteristics in Table S2. Future research could explore adaptive mechanisms to control this trade-off, for example via learned confidence measures, context-aware prior selection, or user preferences, etc. In addition, while most current methods focus on static scenes, extending these approaches to dynamic scenarios presents an exciting direction, particularly in handling temporal consistency and motion-induced artifacts.

## 4.2 Memory-efficient 3D GS

While 3D GS demonstrates remarkable capabilities, its scalability poses significant challenges, particularly when juxtaposed with NeRF-based methods. The latter benefits from the simplicity of storing merely the parameters of a learned MLP. This scalability issue becomes acute in the context of large-scale scene management, where the computational and memory demands escalate substantially. Consequently, there is an urgent need to optimize memory usage in both model training and storage. Please see the excellent surveys [5, 10] for more insights on GS compression.

Recent research has pursued two primary directions to address memory efficiency. First, several approaches focus on **reducing the number of 3D Gaussians** [31, 124, 188]. These methods either employ strategic pruning of low-impact Gaussians, such as the volume-based masking [124], or represent neighboring Gaussians using the same properties stored within a “local anchor” obtained by clustering [160], hash-grid [31], etc. Second, researchers have developed methods for **compressing Gaussian’s properties** [31, 124, 183]. For instance, Niedermayr et al. [183] compressed color and Gaussian parameters into compact codebooks, using sensitivity measures for effective quantization and fine-tuning. HAC [31] predicted the probability of each quantized attribute using Gaussian distributions and then devise an adaptive quantization module. These directions are not mutually exclusive; instead, one framework might use a hybrid approach combining multiple strategies.

While current compression techniques have achieved significant storage reduction ratios (often by factors of 10-20×), several challenges remain. One practical challenge is deploying 3D GS on edge devices, where tight memory budgets can limit how much of a large scene can be stored or loaded locally. The field particularly needs advances in memory efficiency during the training phase, potentially through quantization-aware training protocols, the development of

Manuscript submitted to ACM

<!-- page 10 of 41 -->

10

Guikun Chen and Wenguan Wang

scene-agnostic, reusable codebooks, etc. Furthermore, optimizing the trade-off between compression efficiency and visual fidelity remains an open problem.

## 4.3 Photorealistic 3D GS

The current rendering pipeline of 3D GS (Sec. 3.1) is straightforward and involves several drawbacks. For instance, the simple visibility algorithm may lead to a drastic switch in the depth/blending order of Gaussians. The visual fidelity of rendered images, including aspects such as aliasing, reflections, and artifacts, can be further optimized.

Recent research has focused on addressing three main aspects of visual quality, with aliasing being specific to 3D GS’s rendering algorithm, while reflection and blur handling represent broader challenges in 3D reconstruction. **i) Aliasing**. Due to the discrete sampling paradigm (viewing each pixel as a single point instead of an area), 3D GS is susceptible to aliasing when dealing with varying resolutions, which leads to blurring or jagged edges. Solutions emerged at both training and inference stages. Researchers developed training-time improvements from the sampling rate perspective and introduced schemes such as multi-scale Gaussians [283], 2D Mip filter [303] (predecessor of Mip-NeRF [12]), and conditioned logistic function [145]. Inference-time solutions, such as 2D scale-adaptive filtering [231], offer enhanced fidelity that can be integrated into any existing 3D GS frameworks. **ii) Challenging objects**. Realistic reconstruction of objects with complex appearance, such as reflective, transparent, highly glossy, or anisotropic surfaces, remains a long-standing problem. 3D GS inherits these difficulties because its rasterization-based pipeline only approximates secondary effects. Recent works therefore extend 3D GS with shading functions defined on per-Gaussian normals to better handle reflective and specular surfaces [102], with mirror attributes and plane-mirror imaging to reconstruct mirror geometry and reflections [171], and with anisotropic view-dependent appearance fields that more faithfully capture specular and anisotropic components [290], as well as relightable Gaussian representation [214]. Despite these advances, robust reconstruction of reflective and transparent objects in general scenes remains challenging. **iii) Blur**. While 3D GS excels on carefully curated datasets, real-world captures often suffer from blurs such as motion blur and defocus blur. Recent approaches explicitly incorporated blur modeling during training, employing techniques such as coarse-to-fine kernel optimization [193] and photometric bundle adjustment [325] to address this challenge.

While the approximations made in GS (Sec. 3.1) contribute to its efficiency, they also underlie artifacts such as aliasing and blur, and limit the accuracy of illumination estimation and the modeling of challenging objects. Most existing efforts focus on specific failure modes (e.g., anti-aliasing, deblurring, or handling particular challenging objects) rather than providing a universal solution. In practice, one can first diagnose which issues are present in a scene (e.g., aliasing, blur, or reflective and transparent objects) and then apply targeted optimization strategies. For static object reconstruction in particular, faithfully modeling challenging objects such as reflective, transparent, or highly view-dependent surfaces remains difficult despite recent progress, and extending these capabilities to dynamic or relightable scenes further increases the complexity. The ultimate goal is to develop more general reconstruction systems that alleviate these limitations, either through fundamental improvements to 3D GS or through brand-new architectures.

## 4.4 Improved Optimization Algorithms

The optimization of 3D GS presents several challenges that affect the quality of reconstruction. These include issues with convergence speed, visual artifacts from improper Gaussians, and the need for better regularization during optimization. The raw optimization method (Sec. 3.2) might lead to overreconstruction in some regions while underrepresenting others, resulting in blur and visual inconsistencies.

Manuscript submitted to ACM

<!-- page 11 of 41 -->

A Survey on 3D Gaussian Splatting

11

Three main directions stand out for improving the optimization of 3D GS. **i) Additional Regularization** (e.g., frequency [314] and geometry [139, 160]). Geometry-aware approaches have been particularly successful, preserving scene structure through the incorporation of local anchor points [160], depth and surface constraints [28, 304, 310], Gaussian volumes [27], etc. **ii) Optimization Procedure Enhancement** [34, 247, 304]. While the original strategy of density control (Sec. 3.2.2) has proven valuable, considerable room for improvement remains. For example, GaussianPro [34] addresses the challenge of dense initialization in texture-less surfaces and large-scale scenes through an advanced Gaussian densification strategy. **iii) Constraint Relaxation**. Reliance on external tools/algorithms can introduce errors and cap the system’s performance potential. For instance, SfM, commonly used in the initialization process, is error-prone and struggle with complex scenes. Recent works have begun exploring COLMAP-free [219] approaches utilizing stream continuity [59, 229], potentially enabling learning from internet-scale unposed video datasets. This line of work removes the dependency on pre-computed SfM by jointly optimizing camera poses and Gaussian parameters in an offline/batch manner. Readers interested in the online counterpart of this unknown-pose problem (tracking + mapping under real-time constraints) are referred to Sec. 5.1 on GS-based SLAM.

Though impressive, existing methods primarily concentrate on optimizing Gaussians to accurately reconstruct scenes from scratch, neglecting a challenging yet promising solution which reconstructs scenes in a few-shot manner through established “meta representations”. Such solution could enable adaptive meta-learning strategies that combine scene-specific and general knowledge. See “learning physical priors from large-scale data” in Sec. 7 for further insights.

## 4.5 3D Gaussian with More Properties

Despite impressive, the properties of 3D Gaussian (Sec. 3.1) are designed to be used for novel-view synthesis only. By augmenting 3D Gaussian with additional properties, such as linguistic [202, 226, 347], semantic/instance [24, 295, 332], and spatial-temporal [292] properties, 3D GS demonstrates its considerable potential to revolutionize various domains.

Here we list several interesting applications using 3D Gaussians with specially designed properties. i) **Language Embedded Scene Representation** [202, 226, 347]. Due to the high computational and memory demands of current language-embedded scene representations, Shi et al. [226] proposed a quantization scheme that augments 3D Gaussian with streamlined language embeddings instead of the original high-dimensional embeddings. This method also mitigated semantic ambiguity and enhanced the precision of open-vocabulary querying by smoothing out semantic features across different views, guided by uncertainty values. **ii**) **Scene Understanding and Editing** [24, 295, 332]. Feature 3DGS [332] integrated 3D GS with feature field distillation from 2D foundation models. By learning a lower-dimensional feature field and applying a lightweight convolutional decoder for upsampling, Feature 3DGS achieved faster training and rendering speeds while enabling high-quality feature field distillation, supporting applications like semantic segmentation and language-guided editing. **iii**) **Spatiotemporal Modeling** [148, 292] (task-centric summary and comparisons are given in Sec. 5.2). To capture the complex spatial and temporal dynamics of 3D scenes, Yang et al. [292] conceptualized spacetime as a unified entity and approximates the spatiotemporal volume of dynamic scenes using a collection of 4D Gaussians. The proposed 4D Gaussian representation and corresponding rendering pipeline are capable of modeling arbitrary rotations in space and time and allow for end-to-end training.

## 4.6 Hybrid Representation

Rather than augmenting 3D Gaussian with additional properties, another promising avenue of adapting to downstream tasks is to introduce structured information (e.g., spatial MLPs and grids) tailored for specific applications.

Manuscript submitted to ACM

<!-- page 12 of 41 -->

12

Guikun Chen and Wenguan Wang

Next we showcase various fascinating uses of 3D GS with specially devised structured information. i) **Facial Expression Modeling**. Considering the challenge of creating high-fidelity 3D head avatars under sparse view conditions, Gaussian Head Avatar [277] introduced controllable 3D Gaussians and an MLP-based deformation field. Concretely, it captured detailed facial expressions and dynamics by optimizing neutral 3D Gaussians alongside the deformation field, thus ensuring both detail fidelity and expression accuracy. **ii**) **Spatiotemporal Modeling** (task-centric summary and comparisons are given in Sec. 5.2). Yang et al. [291] proposed to reconstruct dynamic scenes with deformable 3D Gaussians. The deformable 3D Gaussians are learned in a canonical space, coupled with a deformation field (i.e., a spatial MLP) that models the spatial-temporal dynamics. The proposed method also incorporated an annealing smoothing training mechanism to enhance temporal smoothness without additional computational costs. **iii**) **Style Transfer**. Saroha et al. [218] proposed GS in style, an advanced approach for real-time neural scene stylization. To maintain a cohesive stylized appearance across multiple views without compromising on rendering speed, they used pre-trained 3D Gaussians coupled with a multi-resolution hash grid and a small MLP to produce stylized views. In a nutshell, incorporating structured information can serve as a complementary part for adapting to tasks that are incompatible with the sparsity and disorder of 3D Gaussians.

## 4.7 New Rendering Algorithm for 3D Gaussians

While the rasterization-based pipeline of 3D GS offers impressive real-time performance, it still suffers from the inherent limitations, including inefficient handling of highly-distorted cameras (for robotics), secondary rays (for optical effects like reflections and shadows), and stochastic ray sampling (needed in various existing pipelines). In addition, the assumptions that Gaussians do not overlap and can be sorted accurately using only centers are often violated in practice, leading to temporal artifacts when camera movement changes sorting order. This issue is closely related to the long-standing problem of transparency and visibility ordering in classical rasterization, where order-independent transparency (OIT) methods aim to reduce sorting artifacts. Weighted-blended OIT [169] provides a widely-used solution that approximates transparency without explicit per-pixel sorting.

Recent works [36, 166, 176] explored ray tracing based rendering algorithms as an alternative. For instance, GaussianTracer [176] introduced a new ray tracing implementation for Gaussian primitives, and devised several accelerating strategies according to the uneven density and interleaved nature of Gaussians. EVER [166] deivsed a physically accurate, constant density ellipsoid representation that allows for the exact computation of the volume rendering integral, rather than relying on somewhat satisfactory approximations. This advancement eliminates popping artifacts.

Thanks to the fundamental paradigm shift, several exciting possibilities might emerge, including advanced optical effects (reflection, refraction, shadows, global illumination, etc.), support for complex camera models (highly-distorted lenses, rolling shutter effects, etc.), physically accurate rendering with true directional appearance evaluation (vs. tile based approximation), and more. While these capabilities currently come with additional computational costs, they provide essential building blocks for future research in inverse rendering, physical material modeling, relighting, and complex scene reconstruction.

## 4.8 Kernel Engineering

Gaussian kernel is intrinsically smooth with infinite spatial support. Consequently, representing sharp boundaries, thin surfaces, and piecewise-planar structures can be parameter-inefficient: capturing high-frequency details requires aggressive densification and careful regularization. Furthermore, overlapping semi-transparent splats can produce cloudy artifacts near discontinuities due to the kernel’s low-pass nature and cross-boundary leakage. Manuscript submitted to ACM

<!-- page 13 of 41 -->

A Survey on 3D Gaussian Splatting

13

To address these limitations, a growing body of work revisits the geometric primitive and the splatting operator. These efforts can be broadly categorized as follows: **i) Surface-aligned primitives** [40, 85] constrain splatted elements to align with local tangent planes. By utilizing planar or near-planar parameterizations alongside geometric regularizers, this direction explicitly forces primitives to match the underlying surface geometry, thereby improving multi-view consistency and the quality of extracted meshes. **ii) Alternative distributions and shape modifications** [91, 130, 152, 153, 337] alter the mathematical formulation and spatial footprint of the kernel to handle sharp transitions. By replacing the standard Gaussian with bounded-support Beta distributions, asymmetric cuts, deformable radial bases, or heavy-tailed mixtures with subtractive components (e.g., scooping), these methods provide finer control over local attenuation. This prevents cross-boundary density leakage and allows for a more compact representation of complex frequency profiles and hard edges. **iii) Non-Gaussian geometric primitives and operator redesigns** [36, 56, 78, 294] abandon the standard ellipsoid in favor of alternative shapes, or fundamentally modify the rendering operator (Sec. 4.7). This includes utilizing 3D smooth convexes, trilinear point splatting into image pyramids, or bi-scale pipelines that combine standard graphics rasterization with sorting-free splatting. These redesigns natively accommodate distinct geometric features and bypass the limitations of pure Gaussian rasterization.

Despite rapid progress, kernel engineering introduces new practical trade-offs. Alternative parameterizations consistently require custom rendering implementations and tailored primitive management strategies (e.g., modified splitting, merging, and pruning heuristics). Furthermore, standardized evaluation remains challenging, as comparisons are frequently confounded by differences in primitive budgets. As early hybrid pipelines begin to emerge, a promising direction lies in the principled compression and adaptive allocation of heterogeneous primitive types – deploying computationally complex kernels only where specific geometric intricacies demand them.

## 5 APPLICATION AREAS AND TASKS

Building on the rapid advancements in 3D GS, a wide range of innovative applications has emerged across multiple domains (c.f . Fig. 3) such as robotics (Sec. 5.1), dynamic scene reconstruction and representation (Sec. 5.2), generation and editing (Sec. 5.3), avatar (Sec. 5.4), medical systems (Sec. 5.5), large-scale scene reconstruction (Sec. 5.6), physics (Sec. 5.7), and even other scientific disciplines [129, 266, 318, 320]. Here, we highlight key examples that underscore the transformative impact and potential of 3D GS and offer a more comprehensive collection in [Github.](https://github.com/guikunchen/Awesome3DGS) We also provide a collection of representative datasets (c.f . Table S3) according to our taxonomy.

## 5.1 Robotics

The evolution of scene representation in robotics has been profoundly shaped by NeRF. However, NeRF’s computational cost poses a critical bottleneck for real-time applications. The shift from implicit to explicit representation not only accelerates optimization but also unlocks direct access to spatial and structural scene data, making 3D GS a transformative tool for robotics. Its ability to balance high-fidelity reconstruction with computational efficiency positions 3D GS as a cornerstone for advancing robotic perception, manipulation, and navigation in real-world environments.

The integration of GS into robotic systems has yielded advancements across three core domains. In **SLAM**, GS-based methods [44, 54, 61, 62, 79, 80, 86, 97, 110, 121, 135, 168, 196, 238, 246, 279, 306, 339] excel in real-time dense mapping but face inherent trade-offs. Visual SLAM frameworks, particularly RGB-D variants [110, 238, 306], leverage depth supervision for geometric fidelity but falter in low-texture or motion-degraded environments. RGB-only approaches [86, 168, 216] circumvent depth sensors but grapple with scale ambiguity and drift. Multi-sensor fusion strategies, such as LiDAR integration [79, 121, 262], enhance robustness in unstructured settings at the cost of calibration complexity. Manuscript submitted to ACM

<!-- page 14 of 41 -->

14

Guikun Chen and Wenguan Wang

![Image block](images/chen2024_3dgs-survey_p14_b3.png)

Fig. 3. Typical applications benefited from GS (Sec. 5). Some images are borrowed from [126, 161, 243, 272, 274, 338] and redrawn.

Semantic SLAM [97, 135, 280, 339] extends scene understanding through object-level semantics but struggles with scalability due to lighting sensitivity in color-based methods or computational overhead in feature-based methods. GS-based SLAM can be viewed as the online counterpart of pose-free reconstruction in Sec. 4.4: both address unknown poses by jointly optimizing camera trajectories and the Gaussian map, but SLAM operates sequentially with real time constraints and additional mechanisms to control drift (e.g., keyframe selection and loop closure). 3D GS based **manipulation** [3, 95, 159, 227, 328] bypasses the need for auxiliary pose estimation in NeRF-based methods, enabling rapid single-stage tasks like grasping in static environments via geometric and semantic attributes encoded in Gaussian properties. Multi-stage manipulation [159, 227], where environmental dynamics demand real-time map updates, requires explicit modeling of dynamic adjustments (e.g., object motions and interactions), material compliance, etc.

The advancement of 3D GS in robotics faces three pivotal challenges. First, adaptability in dynamic and unstructured environments remains critical: real-world scenes are rarely static, requiring systems to continuously update representations amid motion, occlusions, and sensor noise without sacrificing accuracy. Second, current semantic mapping methods rely on costly, scene-specific optimization processes, limiting generalizability and scalability for real-world deployment. Third, unlike NeRF based systems which can use MLP parameters as input features for downstream decision-making, 3D Gaussians’ inherent lack of spatial order complicates feature aggregation, with no standardized framework yet established. Bridging the gap between high-fidelity reconstruction and actionable semantic/physical understanding will define the next frontier for 3D GS, moving beyond passive mapping towards embodied intelligence.

## 5.2 Dynamic Scene Reconstruction

Dynamic scene reconstruction refers to the process of capturing and representing the three-dimensional structure and appearance of a scene that changes over time [72, 190, 191, 199]. This involves creating a digital model that accurately reflects the geometry, motion, and visual aspects of the objects in the scene as they evolve. Dynamic scene reconstruction is crucial in various applications, e.g., VR/AR, 3D animation, and autonomous driving [281, 331, 335].

The key to adapt 3D GS to dynamic scenes is the modeling of temporal dimension which allows for the representation of scenes that change over time. 3D GS based methods [9, 42, 47, 73, 92, 109, 117, 127, 141, 143, 148, 162, 221, 224, 255, 263, 291, 292, 300] for dynamic scene reconstruction can generally be divided into two main categories as discussed in Manuscript submitted to ACM

<!-- page 15 of 41 -->

A Survey on 3D Gaussian Splatting

15

Sec. 4.5 and Sec. 4.6. The first category utilizes **additional fields** like spatial MLPs or grids to **model deformation** (Sec. 4.6). For example, Yang et al. [291] first proposed deformable 3D Gaussians tailored for dynamic scenes. These 3D Gaussians are learned in a canonical space and can be used to model spatial-temporal deformation with an implicit deformation field (implemented as an MLP). GaGS [161] devised the voxelization of a set of Gaussian distributions, followed by the use of sparse convolutions to extract geometry-aware features, which are then utilized for deformation learning. On the other hand, the second category is based on the idea that scene changes can be **encoded into the 3D Gaussian representation** with a specially designed rendering process (Sec. 4.5). For instance, Luiten et al. [162] introduced dynamic 3D Gaussians to model dynamic scenes by keeping the properties of 3D Gaussians unchanged over time while allowing their positions and orientations to change. Yang et al. [292] designed a 4D Gaussian representation, where additional properties are used to represent 4D rotations and spherindrical harmonics, to approximate the spatial-temporal volume of scenes.

While 3D GS advances dynamic scene reconstruction by modeling per-Gaussian deformations, its reliance on finegrained primitives limits scalability and robustness. Current methods struggle to balance computational efficiency and precision: small-scale reconstructions unify dynamic and static elements but become intractable in large environments, often requiring manual priors to segment regions – a barrier in unstructured settings. Furthermore, the absence of object-level motion reasoning leads to artifacts and poor generalization over long sequences. Future work might prioritize object-centric frameworks that group Gaussians into persistent entities so as to model inherent motion disentanglement (dynamic vs. static).

## 5.3 Generation and Editing

Content generation and editing are two closely related capabilities in 3D creation pipelines. Generation aims to synthesize new assets or scenes from high-level conditions such as text and images, while editing focuses on modifying existing content in a controlled way. In this subsection, we concentrate on works that take 3D GS as the target representation. Please see the excellent survey [75] for more insights on the GS based generation and editing methods.

• **Generation.** Recent advances in GS based generation [14, 33, 53, 76, 100, 113, 125, 131, 140, 144, 149, 155, 170, 179, 186, 207, 243, 244, 269, 276, 284, 287, 289, 296, 298, 309, 313, 333, 343, 346] can be roughly grouped along the underlying learning paradigm. **Optimization**-based methods follow the score-distillation paradigm: a powerful 2D or multi-view diffusion model is queried from many camera poses, and its gradients are back-propagated through the differentiable GS renderer to update Gaussian parameters. Early text- and image-to-3D pipelines such as DreamGaussian [244] and GaussianDreamer [296] treat each scene independently and directly optimize positions, scales, colors, and opacities to match diffusion-model guidance while respecting RGB reconstruction losses. This per-scene fitting often yields high-fidelity geometry and appearance for object- and scene-level content, and can be naturally extended to dynamic or 4D generation with temporal regularization. However, it incurs heavy computational cost (minutes to hours per prompt) and is prone to Janus ambiguity, over-smoothing, or texture oversaturation unless additional regularizers, multi-view diffusion priors, or geometry-aware constraints are introduced. **Reconstruction**-based methods decompose the problem into two classical stages: multi-view generation followed by 3D reconstruction. Given a text or image prompt, a pre-trained multi-view or video diffusion model first synthesizes a small set of posed views (and sometimes depth or camera trajectories). A GS reconstructor such as LGM [243] or VividDream [125] then treats these images as supervision and solves a standard multi-view reconstruction problem to obtain Gaussians. This design reuses mature reconstruction pipelines and makes system-level engineering straightforward, but inherits the fundamental limitations of the multi-view generator: imperfect cross-view consistency can lead to noisy surface geometry, duplicated structures, Manuscript submitted to ACM

<!-- page 16 of 41 -->

16

Guikun Chen and Wenguan Wang

and degraded textures, especially in occluded or textureless regions. **Direct 3D generation** methods aim to learn a feed forward or diffusion model that outputs Gaussian fields directly from text or images, without an explicit intermediate image set [22, 76, 179, 185, 309]. Trained on large collections of synthetic or reconstructed data, these models amortize the reconstruction cost and naturally promote multi-view coherence, enabling near-real-time sampling at test time. The main challenges lie in the high-dimensional and highly structured output space (positions, anisotropic covariance, colors, opacity), the need for large, curated 3D training corpora, and maintaining controllability (e.g., disentangling geometry from appearance) while scaling to diverse objects and scenes. Scene-level versions further have to reason about layout, occlusions, and long-range dependencies. Beyond applications, these methods reflect a paradigm shift from per-scene optimization of Gaussians to amortized, feed-forward prediction (often with generative priors), enabling much lower test-time latency and better scalability (Sec. 7).

• **Editing.** Current editing works [24, 29, 46, 50, 70, 83, 87, 92, 120, 158, 164, 184, 203, 221, 258, 264, 295, 300, 311, 316, 332, 342] can be broadly divided into two families. The first leverages **2D image-editing** models (e.g., text- or image conditioned diffusion editors) to drive updates of 3D Gaussians. Representative systems such as GaussianEditor [29, 50, 184] repeatedly render GS views, apply 2D edits, and back-propagate the differences to Gaussian parameters, enabling text- or mask-driven appearance and geometry changes. Follow-up works improve spatial localization and multi-view consistency via attention, view correspondence, or iterative refinement [258, 264, 316], and specialize to style transfer or personalization [311, 342]. While intuitive and compatible with powerful 2D priors, these pipelines remain computationally heavy and can still suffer from unintended deformations due to weak 3D geometry priors. The second family exploits the explicit, point-based nature of 3D GS for **direct manipulation**. Semantic or featureaware approaches enrich Gaussians with labels or embeddings so that users can select and edit subsets of points with text queries, masks, or keypoints [24, 83, 92, 203, 295]. Mesh-coupled methods provide stronger structural control. GaMeS [248] introduces a hybrid “Gaussian Mesh Splatting” representation where each Gaussian is parameterized by the vertices of a mesh face; given either an input mesh or an estimated pseudo-mesh, classical mesh operations or animations induce coherent changes in Gaussian position, scale, and orientation. GaussianMesh [63] similarly defines Gaussians over an explicit mesh and ties the two via joint refinement: GS rendering guides adaptive face and Gaussian splitting, while mesh constraints regularize Gaussian shapes and support large, interactive deformations driven by mesh editing. However, this family faces several practical challenges: it relies on accurate semantic labels or mesh proxies, so errors in segmentation or remeshing can easily produce artifacts, and editing attributes (e.g., texture, geometry, and illumination) still requires careful regularization and cross-view alignment to preserve plausibility.

## 5.4 Avatar

Avatars, the digital representations of users in virtual spaces, bridge physical and digital realms, enabling immersive interaction, identity expression, etc. Spanning entertainment (gaming, virtual influencers), enterprise (AI agents, virtual meetings), healthcare, and education, they underpin metaverse economies. Advances in AR and VR amplify their role in redefining social, industrial, and creative landscapes.

3D GS has emerged as a powerful tool for avatar reconstruction, primarily advancing along two directions: full-body modeling and head-centric modeling. For **full-body avatars** [1, 81, 82, 94, 101, 105, 116, 126, 136, 137, 142, 177, 187, 201, 293, 305, 308, 327], the current methods typically anchor 3D Gaussians in a canonical space and deform them via parametric body models or cage-based rigging to model dynamic motions. These approaches adopt a hybrid deformation strategy: linear blend skinning handles rigid skeletal transformations such as joint rotations, while pose-conditioned deformation fields account for secondary non-rigid effects like muscle jiggles. For **head avatars** [30, 45, 134, 200, 211, Manuscript submitted to ACM

<!-- page 17 of 41 -->

A Survey on 3D Gaussian Splatting

17

214, 270, 326, 336], the emphasis shifts to modeling intricate facial expressions, fine-grained geometry (e.g., wrinkles, hair [163]), and dynamic speech-driven animations. Techniques mainly combine parametric morphable face models (e.g., FLAME) with deformable 3D Gaussians, employing diffusion strategies and expression-aware deformation fields to disentangle rigid head poses from non-rigid facial movements. Both directions exploit the speed advantage and editability of GS to enable fast training, real-time rendering, and precise control over deformations, while addressing challenges in cross-frame correspondence, topology flexibility, and multi-view consistency.

Reconstruction in challenging scenes (e.g., occlusions, sparse single-view inputs, or loose clothing) and enhancing avatar interactivity represent critical challenges and opportunities. Parametric model-free methods, which bypass predefined priors by learning skinning weights directly from data, show promise for such scenarios. Complementary to this, generative models can mitigate ambiguities inherent in underconstrained settings. Further integrating physics based constraints might bridge the gap between static reconstructions and responsive, lifelike interactions, unlocking applications in metaverse, embodied AI, etc.

## 5.5 Endoscopic Scene Reconstruction

Endoscopic Scene reconstruction is pivotal in robot-assisted minimally invasive surgery, enhancing intraoperative navigation, planning, and simulation. Recent advances integrate dynamic radiance fields to address challenges like instrument occlusions and sparse viewpoints in endoscopic videos. However, achieving high fidelity in tissue deformation and topological variation, alongside real-time rendering for latency-sensitive applications, remains critical [90, 157, 338]

This task introduces distinct challenges compared to general dynamic scenes, including sparse training data from limited camera mobility in narrow cavities, tool occlusions obscuring critical regions, and single-view geometry ambiguities. Existing approaches mainly used additional depth guidance to infer the geometry of tissues [90, 157, 338]. For instance, EndoGS [338] integrated depth-guided supervision with spatial-temporal weight masks and surface-aligned regulariza tion terms to enhance the quality and speed of 3D tissue rendering while addressing tool occlusion. EndoGaussian [157] introduced two new strategies: holistic Gaussian initialization for dense initialization and spatiotemporal Gaussian tracking for modeling surface dynamics. Zhao et al. [324] argued that these methods suffer from under-reconstruction and proposed to alleviate this problem from frequency perspectives. In addition, EndoGSLAM [254] and Gaussian Pancake [16] devised SLAM systems for endoscopic scenes and showed significant speed advantages.

Advancing endoscopic 3D reconstruction requires targeted efforts in both data and dynamics modeling. Data limitations arise from single-viewpoint videos, which produce ill-posed reconstruction problems due to instrument occlusions and constrained camera mobility, leaving critical tissue regions unobserved. While depth estimators provide temporary workarounds, integrating multi-view camera systems addresses the root cause. In addition, existing datasets often feature truncated sequences (e.g., 4∼8𝑠 in EndoNeRF [257]), which fail to capture prolonged tissue deformation dynamics or complex surgical workflows. Extending temporal coverage to include longer, clinically representative sequences would benefit downstream applications as aforementioned. Modeling limitations persist in current methods, which often represent tissue dynamics at the Gaussian level rather than object- or 3D region-level. This reduces their capacity to encode semantically meaningful anatomical interactions and deserves further explorations.

## 5.6 Large-scale Scene Reconstruction

Large-scale scene reconstruction is a critical component in fields such as autonomous driving and aerial surveying. Before the emergence of 3D GS, the task has been approached using NeRF based methods, which, while effective for smaller scenes, often fall short in detail and rendering speed when scaled to larger areas (e.g., over 1.5 𝑘𝑚<sup>2</sup>). Though Manuscript submitted to ACM

<!-- page 18 of 41 -->

18

Guikun Chen and Wenguan Wang

GS has demonstrated considerable advantages over NeRFs, the direct application of GS to large-scale environments introduces significant challenges. GS requires an immense number of Gaussians to maintain visual quality, leading to prohibitive GPU memory demands and computational burdens. For instance, a scene spanning $2 . 7 \: k m ^ { 2 }$ may require over 20 million Gaussians, pushing the limits of commonly used GPUs (e.g., NVIDIA A100 40GB) [156].

To address the highlighted challenges, researchers have made significant strides in two key areas: i) For **training**, a divide-and-conquer strategy [112, 147, 156, 209] has been adopted, which segments a large scene into multiple, independent cells. This facilitates parallel optimization for expansive environments. An additional challenge lies in maintaining visual quality, as large-scale scenes often feature texture-less surfaces that can hamper the effectiveness of optimization such as Gaussian initialization and density control (Sec. 3.2). Enhancing the optimization algorithm presents a viable solution to mitigate this issue [34, 147]. **ii**) Regarding **rendering**, the adoption of the Level of Details (LoD) technique from computer graphics has proven instrumental. LoD adjusts the complexity of 3D scenes to balance visual quality with computational efficiency. Current implementations involve feeding only the essential Gaussians to the rasterizer [147], or designing explicit LoD structures like the Octree [209] and hierarchy [112]. Furthermore, integrating extra input modalities like LiDAR can further enhanced the reconstruction process [262, 265, 274].

One prominent challenge lies in handling sparse or incomplete capture data, which can be mitigated through few-shot adaptation schemes (see Sec. 4.1) or generalizable priors (see “learning physical priors from large-scale data” in Sec. 7). Meanwhile, memory and computational bottlenecks can be addressed via distributed learning strategies [323], such as parameter partitioning across GPU clusters and parallel batched multi-view optimization.

## 5.7 Physics

The simulation of complex real-world dynamics, such as seed dispersal, fracture, or fluid motion, is pivotal for applications spanning VR, animation, scientific modeling, and emerging “world models”, where usefulness hinges not only on visual plausibility but also on adherence to physical laws. While recent diffusion-based 4D generation frameworks can synthesize visually compelling dynamics, they often optimize for appearance metrics and may violate basic conservation principles or material constraints. In this context, 3D GS provides an attractive bridge between graphics and simulation: Gaussians can be interpreted simultaneously as rendering primitives and as particles or elements in a numerical solver, making it natural to embed physical priors directly into the scene representation.

Existing methods differ mainly in how they couple Gaussians with explicit simulators. One line of work adopts classical schemes such as the material point method (MPM) [84] and position-based dynamics (PBD) [180], and replaces traditional grid or mesh discretizations with 3D Gaussians. In PhysGaussian [272], for instance, the same Gaussian set is used for both continuum-mechanics-based time integration and for splatting, so physical states evolve on exactly what is rendered. PBD-style pipelines such as Gaussian Splashing [55] treat Gaussians as particles subject to constraints, enabling two-way coupling between deformable solids and fluids, while other systems like GASP [17] derive mesh-like parameterizations from Gaussians to interface with conventional solvers. These approaches achieve high-fidelity dynamics within their target regimes but inherit the computational cost, stability issues, and parameter tuning burden of the underlying simulators. A complementary direction focuses on learning material parameters or effective constitutive models from data while keeping Gaussians as the canonical representation. Physics3D [151] builds a viscoelastic MPM on top of 3DGS and estimates elastic and plastic properties by distilling priors from video diffusion models. DreamPhysics [89], PhysDreamer [321], PhysMotion [103], and Feature Splatting [203] similarly use generative video models as weak teachers for dynamics or material behavior, whereas mass-spring formulations such as Spring-Gaus [330] encode stiffness and damping explicitly via springs attached to Gaussians. Most frameworks treat Manuscript submitted to ACM

<!-- page 19 of 41 -->

A Survey on 3D Gaussian Splatting

19

Gaussians as discrete particles inside differentiable simulators (with one exception of continuous formulations such as GausSim [223]), and backpropagate through simulation and rendering to jointly adjust appearance and physics.

Despite rapid progress, physics-based GS is still far from a general-purpose physical world model. Current systems are often specialized to narrow regimes (e.g., a limited set of elastic behaviors), and extending a single Gaussian-based formulation to simultaneously handle rigid, elastic, plastic, granular, and fluid dynamics remains open. Interactions are typically restricted to a few objects in controlled scenes; robust multi-contact, multi-material interactions in cluttered environments still rely on manual priors, and long-horizon rollouts accumulate numerical and modeling errors. Moreover, physical supervision is weak: diffusion-based teachers target perceptual realism rather than quantitative accuracy, and existing datasets rarely provide ground-truth material parameters or stress/strain measurements. Bridging these gaps will require tighter integration between adaptive physics engines and Gaussian representations, better benchmarks for physical correctness, and learning schemes that combine explicit simulation with large-scale data-driven priors.

## 6 PERFORMANCE COMPARISON

In this section, we provide empirical evidence by presenting the performance of several 3D GS algorithms previously discussed. The diverse applications of 3D GS across numerous tasks, coupled with the custom-tailored algorithmic designs for each task, render a uniform comparison of all 3D GS algorithms across a single task or dataset impracticable. For comprehensiveness, we provide a collection of representative datasets in Table S3 Following the taxonomy outlined Fig. 1. Due to the limited space, we have chosen several representative tasks for an in-depth performance evaluation. The performance scores are primarily sourced from the original papers, except where indicated otherwise.

Quantitative results (e.g., PSNR) can vary noticeably across implementations and hyperparameters (e.g., densification schedules and pruning resets), even on the same dataset. Since exhaustively enumerating these settings is beyond the scope of this survey, we link the original codebases and configurations in our [benchmark repository](https://github.com/guikunchen/3DGS-Benchmarks) to support reproducibility. Likewise, memory and storage footprint are important practical factors but are highly benchmarkdependent, varying with the dataset/scene (e.g., scale, duration, texture complexity, and number of views), the target quality, and implementation choices. Consequently, GS methods may exhibit either smaller or larger VRAM/storage than NeRF baselines depending on the dataset and the chosen capacity. We therefore provide the same [repository](https://github.com/guikunchen/3DGS-Benchmarks) to help readers reproduce and inspect footprint-quality trade-offs under specific datasets/settings of interest.

## 6.1 Performance Benchmarking: Localization

The localization task in SLAM involves determining the precise position and orientation of a robot or device.

• **Dataset:** Replica [232] dataset is a collection of 18 highly detailed 3D indoor scenes. These scenes are not only visually realistic but also offer data including dense meshes, high-quality textures, and detailed semantic information for each element. Following [235], three sequences about rooms and five sequences about offices are used for the evaluation.

• **Benchmarking Algorithms:** For performance comparison, we involve four recent 3D GS based algorithms [110, 168, 279, 306] and six typical SLAM methods [215, 341].

• **Evaluation Metric:** The root mean square error (RMSE) of the absolute trajectory error (ATE) is a commonly used metric in evaluating SLAM systems [233], which measures the root mean square of the Euclidean distances between the estimated and true positions over the entire trajectory.

• **Result:** As shown in Table S4, the recent 3D Gaussians based localization algorithms have a clear advantage over existing NeRF based dense visual SLAM. For example, SplaTAM [110] achieves a trajectory error improvement of ∼**50**%, decreasing it from 0.52cm to **0.36cm** compared to the previous state-of-the-art (SOTA) [215]. We attribute this to the Manuscript submitted to ACM

<!-- page 20 of 41 -->

20

Guikun Chen and Wenguan Wang

dense and accurate 3D Gaussians reconstructed for scenes, which can handle the noise of real sensors. This reveals that effective scene representations can improve the accuracy of localization tasks.

## 6.2 Performance Benchmarking: Static Scenes

Rendering focuses on transforming computer-readable information (e.g., 3D objects in the scene) to pixel-based images. This section focuses on evaluating the quality of rendering results in static scenes.

• **Dataset:** Replica [232] (Sec. 6.1) is used for comparison. The testing views are the same as [235].

• **Benchmarking Algorithms:** For performance comparison, we involve four recent papers which introduce 3D Gaussians into their systems [110, 168, 279, 306], as well as three dense SLAM methods [215, 341].

• **Evaluation Metric:** Peak signal-to-noise ratio (PSNR), structural similarity (SSIM) [259], and learned perceptual image patch similarity (LPIPS) [317] are used for measuring RGB rendering performance.

• **Result:** Table S5 shows that 3D Gaussians based systems generally outperform the three dense SLAM competitors. For example, Gaussian-SLAM [306] establishes new SOTA and outperforms previous methods by a large margin. Compared to Point-SLAM [215], GSSLAM [168] is about **578** times faster in achieving very competitive accuracy. In contrast to previous method [215] that relies on depth information, such as depth-guided ray sampling, for synthesizing novel views, 3D GS based system eliminates this need, allowing for high-fidelity rendering for any views.

## 6.3 Performance Benchmarking: Dynamic Scenes

This section focuses on evaluating the rendering quality in dynamic scenes.

• **Dataset:** D-NeRF [199] dataset includes videos with 50 to 200 frames each, captured from unique viewpoints. It features synthetic, animated objects in complex scenes, with non-Lambertian materials. The dataset provides 50 to 200 training images and 20 test images per scene. The testing views are the same as the original paper [199].

• **Benchmarking Algorithms:** For performance comparison, we involve five recent papers that model dynamic scenes with 3D GS [161, 263, 291, 292, 300], as well as six NeRF based approaches [72, 199, 250].

• **Evaluation Metric:** The same metrics as in Sec. 6.2, i.e., PSNR, SSIM [259], and LPIPS [317], are used for evaluation.

• **Result:** From Table S6 we can observe that 3D GS based methods outperform existing SOTAs by a clear margin. The static version of 3D GS [111] fails to reconstruct dynamic scenes, resulting in a sharp drop in performance. By modeling the dynamics, D-3DGS [291] outperforms the SOTA method, FFDNeRF [72], by **6.83**dB in terms of PSNR. These results indicate the effectiveness of introducing additional properties or structured information to model the deformation of Gaussians so as to model the scene dynamics.

## 6.4 Performance Benchmarking: Human Avatar

Human avatar modeling aims to create the model of human avatars from a given multi-view video.

• **Dataset:** ZJU-MoCap [195] is a prevalent benchmark in human modeling from videos, captured with 23 synchronized cameras at a 1024×1024 resolution. Six subjects (i.e., 377, 386, 387, 392, 393, and 394) are used for evaluation [260]. The same testing views following [66] are adopted.

• **Benchmarking Algorithms:** For performance comparison, we involve three recent papers which model human avatar with 3D GS [82, 126, 201], as well as six human rendering approaches [66, 195, 260].

• **Evaluation Metric:** PSNR, SSIM [259], and LPIPS\* [317] are used for measuring RGB rendering performance.

• **Result:** Table S7 presents the numerical results of top-leading solutions in human avatar modeling. We observe that introducing 3D GS into the framework leads to consistent performance improvements in both rendering quality and Manuscript submitted to ACM

<!-- page 21 of 41 -->

A Survey on 3D Gaussian Splatting

21

speed. For instance, GART [126] outperforms current SOTA, Instant-NVR [66], by **1.21**dB in terms of PSNR. Considering the enhanced fidelity, inference speed and editability, 3D GS based avatar modeling may revolutionize the field of 3D animation, interactive gaming, etc.

## 6.5 Performance Benchmarking: Surgical Scenes

3D reconstruction from endoscopic video is critical to robotic-assisted minimally invasive surgery.

• **Dataset:** EndoNeRF [257] dataset presents a specialized collection of stereo camera captures, comprising two samples of in-vivo prostatectomy. It is tailored to represent real-world surgical complexities, including challenging scenes with tool occlusion and pronounced non-rigid deformation. The same testing views as in [307] are used.

• **Benchmarking Algorithms:** For performance comparison, we involve three works which reconstruct dynamic 3D endoscopic scenes with GS [90, 157, 324], as well as three NeRF-based surgical reconstruction approaches [257, 307]. • **Evaluation Metric:** PSNR, SSIM [259], and LPIPS [317] are adopted for evaluation.

• **Result:** Table S8 shows that introducing the explicit representation of 3D Gaussians leads to several significant improvements. For instance, EndoGaussian [157] outperforms a strong baseline, EndoSurf [307], among all metrics. In particular, EndoGaussian demonstrates an approximate 200-fold increase in speed while consuming just 10% of the GPU resources, a gap that mainly stems from the GS pipeline and lightweight dynamic modeling rather than unusually heavyweight NeRF baselines. These impressive results attest to the efficiency of GS-based methods, which not only expedite processing but also minimize GPU load, thus easing the demands on hardware. Such attributes are significant for surgical application deployment, where optimized resource usage can be a key determinant of practical utility.

## 7 FUTURE RESEARCH DIRECTIONS

**Recent Trends and The Big Picture.** Recent work on GS has pushed it from a fast alternative to NeRFs towards a general representation for 3D world modeling. Early work showed that explicit 3D Gaussians can be optimized to capture complex static and dynamic scenes with high fidelity, inspiring follow-up research on more compact, generalizable, and semantics-aware splat-based models [61, 124, 154]. As an explicit scene representation, GS has been applied across a wide range of vision, graphics, and robotics applications [2, 3, 54, 244]. A major recent trend is the shift from per-scene optimization to feed-forward Gaussian prediction. Early pioneering works showed that 3D Gaussians can be inferred directly from sparse views using lightweight, pixel-level feature extractors (e.g., U-Nets) [26, 241]. To improve scalability from object-centric reconstructions to complex scenes, more recent approaches have adopted Transformer-based models [278, 315]. This architectural shift has naturally driven efforts to process increasingly large input sets; by innovating on sequence processing – such as integrating hybrid attention mechanisms [344, 345] or test-time training [249, 319] – current models can now ingest massive multi-view contexts for wide-coverage, scene-level modeling. Simultaneously, this feed-forward paradigm is rapidly expanding its functional scope: recent frameworks can now jointly infer camera parameters from uncalibrated image collections [99], extract robust geometric priors to stabilize downstream prediction tasks [252], and extend spatial prediction into the temporal domain for 4D dynamic generation [165, 208]. Together, these trends point towards Gaussian-based world models that support not only high-quality rendering and reconstruction but also interactive perception, reasoning, and action, with demonstrations in robotics and embodied AI. Concrete discussions on some important directions are given in the following.

• **Physics- and Semantics-aware Scene Representation.** As a new, explicit scene representation technique, 3D Gaussian offers transformative potential beyond merely enhancing novel-view synthesis. It has the potential to pave

Manuscript submitted to ACM

<!-- page 22 of 41 -->

22

Guikun Chen and Wenguan Wang

the way for simultaneous advancements in scene reconstruction and understanding by devising physics- and semantics aware 3D GS systems. While significant progress has been made in physics (Sec. 5.7) and semantics [35, 96, 98, 146, 204, 253] individually, there remains considerable untapped potential in their synergistic integration. This is poised to revolutionize a range of fields and downstream applications. For instance, incorporating prior knowledge such as the general shape of objects can reduce the need for extensive training viewpoints [26, 241] while improving geometry/surface reconstruction [71, 139]. A critical metric for assessing scene representation is the quality of its generated scenes, which encompasses challenges in geometry, texture, and lighting fidelity [29, 60, 92]. By merging physical principles and semantic information within the 3D GS framework, one can expect that the quality will be enhanced, thereby facilitating dynamics modeling [103, 272], editing [24, 332], generation [244, 296], and beyond. In a nutshell, pursuing this advanced and versatile scene representation opens up new possibilities for innovation in computational creativity and practical applications across diverse domains.

• **Learning Physical Priors from Large-scale Data.** As we explore the potential of physics- and semantics-aware scene representations, leveraging large-scale datasets to learn generalizable, physical priors emerges as a promising direction. The goal is to model the inherent physical properties and dynamics embedded within real-world data, transforming them into actionable insights that can be applied across various domains such as robotics and visual effects. Establishing a learning framework for extracting these generalizable priors enables the application of these insights to specific tasks in a few-shot manner. For instance, it allows for rapid adaptation to new objects and environments with minimal data input. Furthermore, integrating physical priors can enhance not only the accuracy and quality of generated scenes but also their interactive and dynamic qualities. This is particularly valuable in AR/VR environments, where users interact with virtual objects that behave in ways consistent with their real-world counterparts. However, the existing body of work on capturing and distilling physics-based knowledge from extensive 2D and 3D datasets remains sparse. Notable efforts in related area include the continuum mechanics based GS systems (Sec. 5.7), and the generalizable Gaussian representation based on multi-view stereo [154]. Further exploration on real2sim and sim2real might offer viable routes for advancements in this field.

• **Modeling Internal Structures of Objects with 3D GS.** Despite the ability of 3D GS to produce highly photorealistic renderings, modeling internal structures of objects (e.g., for a scanned object in computed tomography) within the current GS framework presents a notable challenge. Due to the splatting and density control process, the current representation of 3D Gaussian is unorganized and cannot align well with the object’s actual internal structures. Moreover, there is a strong preference in various applications to depict objects as volumes (e.g., computed tomography). However, the disordered nature of 3D GS makes volume modeling particularly difficult. Li et al. [138] used 3D Gaussians with density control as the basis for the volumetric representation and did not involve the splatting process. X-Gaussian [20] involves the splatting process for fast training and inference but cannot generate volumetric representation. Using 3D GS to model the internal structures of objects remains unanswered and deserves further exploration.

• **3D GS for Simulation in Autonomous Driving and beyond.** Collecting real-world datasets for autonomous driving is both expensive and logistically challenging, yet crucial for training effective image-based perception systems. To mitigate these issues, simulation emerges as a cost-effective alternative, enabling the generation of synthetic datasets across diverse environments. However, the development of simulators capable of producing photorealistic and diverse synthetic data is fraught with challenges. These include achieving a high level of quality, accommodating various control methods, and accurately simulating a range of lighting conditions. While early efforts [281, 331, 335] in reconstructing urban/street scenes with 3D GS have been encouraging, they are just the tip of the iceberg in terms of the full capabilities. There remain numerous critical aspects to be explored, such as the integration of user-defined object models, the Manuscript submitted to ACM

<!-- page 23 of 41 -->

A Survey on 3D Gaussian Splatting

23

modeling of physics-aware scene changes (e.g., the rotation of vehicle wheels), and the enhancement of controllability and quality (e.g., in varying lighting conditions). Mastery of these capabilities would not only advance autonomous systems but also redefine computational understanding of physical spaces — a leap with implications for world models, spatial intelligence, embodied AI, and beyond.

• **Empowering 3D GS with More Possibilities.** Despite the significant potential of 3D GS, the full scope of applications for 3D GS remains largely untapped. A promising avenue for exploration involves augmenting 3D Gaussians with additional attributes (e.g., linguistic and spatiotemporal properties as mentioned in Sec. 4.5) and introducing structured information (e.g., spatial MLPs and grids as mentioned in Sec. 4.6), tailored for specific applications. Moreover, recent studies have begun to unveil the capability of 3D GS in several domains, e.g., point cloud registration [25], image representation and compression [322], and fluid synthesis [55]. These findings highlight a significant opportunity for interdisciplinary scholars to explore 3D GS further.

## 8 CONCLUSIONS

To the best of our knowledge, this survey presents the first comprehensive overview of 3D GS, a groundbreaking technique revolutionizing explicit radiance fields, computer graphics, and computer vision. It delineates the paradigm shift from traditional NeRF based methods, spotlighting the advantages of 3D GS in real-time rendering and enhanced editability. Our in-depth analysis and extensive quantitative studies demonstrate the superiority of 3D GS in practical applications, particularly those highly sensitive to latency. We offer insights into principles, prospective research directions, and the unresolved challenges within this domain. Overall, 3D GS stands as a transformative technology, poised to significantly influence future advancements in 3D reconstruction and representation. This survey is intended to serve as a foundational resource, propelling further exploration and progress in this rapidly evolving field.

## REFERENCES

[1] Rameen Abdal, Wang Yifan, Zifan Shi, Yinghao Xu, Ryan Po, Zhengfei Kuang, Qifeng Chen, Dit-Yan Yeung, and Gordon Wetzstein. 2024. Gaussian Shell Maps for Efficient 3D Human Generation. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[2] Jad Abou-Chakra, Krishan Rana, Feras Dayoub, and Niko Sünderhauf. 2023. Physically embodied gaussian splatting: Embedding physical priors into a visual 3d world model for robotics. In Conf. Rob. Learn.

[3] Jad Abou-Chakra, Krishan Rana, Feras Dayoub, and Niko Sünderhauf. 2024. Physically Embodied Gaussian Splatting: A Realtime Correctable World Model for Robotics. In Proc. Annu. Conf. Robot Learn.

[4] Rachel Albert, Anjul Patney, David Luebke, and Joohwan Kim. 2017. Latency requirements for foveated rendering in virtual reality. ACM Transactions on Applied Perception 14, 4 (2017), 1–13.

[5] Muhammad Salman Ali, Chaoning Zhang, Marco Cagnazzo, Giuseppe Valenzise, Enzo Tartaglione, and Sung-Ho Bae. 2025. Compression in 3d gaussian splatting: A survey of methods, trends, and future directions. arXiv preprint arXiv:2502.19457 (2025).

[6] Kara-Ali Aliev, Artem Sevastopolsky, Maria Kolos, Dmitry Ulyanov, and Victor Lempitsky. 2020. Neural point-based graphics. In Proc. Eur. Conf. Comput. Vis. 696–712.

[7] Max Allan, Jonathan Mcleod, Congcong Wang, Jean Claude Rosenthal, Zhenglei Hu, Niklas Gard, Peter Eisert, Ke Xue Fu, Trevor Zeffiro, Wenyao Xia, et al. 2021. Stereo correspondence and reconstruction of endoscopic data challenge. arXiv preprint arXiv:2101.01133 (2021).

[8] Thiemo Alldieck, Marcus Magnor, Weipeng Xu, Christian Theobalt, and Gerard Pons-Moll. 2018. Video based reconstruction of 3d people models In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 8387–8397.

[9] Jeongmin Bae, Seoha Kim, Youngsik Yun, Hahyun Lee, Gun Bang, and Youngjung Uh. 2024. Per-Gaussian Embedding-Based Deformation for Deformable 3D Gaussian Splatting. arXiv preprint arXiv:2404.03613 (2024).

[10] Milena T Bagdasarian, Paul Knoll, Y Li, Florian Barthel, Anna Hilsmann, Peter Eisert, and Wieland Morgenstern. 2025. 3dgs. zip: A survey on 3d gaussian splatting compression methods. In Computer Graphics Forum, Vol. 44. e70078.

[11] Yanqi Bao, Tianyu Ding, Jing Huo, Yaoli Liu, Yuxin Li, Wenbin Li, Yang Gao, and Jiebo Luo. 2024. 3d gaussian splatting: Survey, technologies, challenges, and opportunities. arXiv preprint arXiv:2407.17418 (2024).

[12] Jonathan T Barron, Ben Mildenhall, Matthew Tancik, Peter Hedman, Ricardo Martin-Brualla, and Pratul P Srinivasan. 2021. Mip-nerf: A multiscale representation for anti-aliasing neural radiance fields. In Proc. IEEE Int. Conf. Comput. Vis. 5855–5864.

Manuscript submitted to ACM

<!-- page 24 of 41 -->

24

Guikun Chen and Wenguan Wang

[13] Jonathan T Barron, Ben Mildenhall, Dor Verbin, Pratul P Srinivasan, and Peter Hedman. 2022. Mip-nerf 360: Unbounded anti-aliased neural radiance fields. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 5470–5479.

[14] Florian Barthel, Arian Beckmann, Wieland Morgenstern, Anna Hilsmann, and Peter Eisert. 2024. Gaussian Splatting Decoder for 3D-aware Generative Adversarial Networks. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. Worksh.

[15] Luis Bolanos, Shih-Yang Su, and Helge Rhodin. 2024. Gaussian Shadow Casting for Neural Characters. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[16] Sierra Bonilla, Shuai Zhang, Dimitrios Psychogyios, Danail Stoyanov, Francisco Vasconcelos, and Sophia Bano. 2024. Gaussian Pancakes: Geometrically-Regularized 3D Gaussian Splatting for Realistic Endoscopic Reconstruction. arXiv preprint arXiv:2404.06128 (2024).

[17] Piotr Borycki, Weronika Smolak, Joanna Waczyńska, Marcin Mazur, Sławomir Tadeja, and Przemysław Spurek. 2024. GASP: Gaussian Splatting for Physic-Based Simulations. arXiv preprint arXiv:2409.05819 (2024).

[18] Chris Buehler, Michael Bosse, Leonard McMillan, Steven Gortler, and Michael Cohen. 2023. Unstructured lumigraph rendering. In Seminal Graphics Papers: Pushing the Boundaries, Volume 2. 497–504.

[19] Holger Caesar, Varun Bankiti, Alex H Lang, Sourabh Vora, Venice Erin Liong, Qiang Xu, Anush Krishnan, Yu Pan, Giancarlo Baldan, and Oscar Beijbom. 2020. nuscenes: A multimodal dataset for autonomous driving. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 11621–11631.

[20] Yuanhao Cai, Yixun Liang, Jiahao Wang, Angtian Wang, Yulun Zhang, Xiaokang Yang, Zongwei Zhou, and Alan Yuille. 2024. Radiative Gaussian Splatting for Efficient X-ray Novel View Synthesis. In Proc. Eur. Conf. Comput. Vis.

[21] Yuanhao Cai, Jiahao Wang, Alan Yuille, Zongwei Zhou, and Angtian Wang. 2024. Structure-aware sparse-view x-ray 3d reconstruction. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 11174–11183.

[22] Yuanhao Cai, He Zhang, Kai Zhang, Yixun Liang, Mengwei Ren, Fujun Luan, Qing Liu, Soo Ye Kim, Jianming Zhang, Zhifei Zhang, et al. 2025. Baking gaussian splatting into diffusion denoiser for fast and scalable single-stage image-to-3d generation and reconstruction. In Proc. IEEE Int. Conf. Comput. Vis. 25062–25072.

[23] Ang Cao and Justin Johnson. 2023. Hexplane: A fast representation for dynamic scenes. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 130–141.

[24] Jiazhong Cen, Jiemin Fang, Chen Yang, Lingxi Xie, Xiaopeng Zhang, Wei Shen, and Qi Tian. 2023. Segment Any 3D Gaussians. arXiv preprint arXiv:2312.00860 (2023).

[25] Jiahao Chang, Yinglin Xu, Yihao Li, Yuantao Chen, and Xiaoguang Han. 2024. GaussReg: Fast 3D Registration with Gaussian Splatting. In Proc. Eur. Conf. Comput. Vis.

[26] David Charatan, Sizhe Li, Andrea Tagliasacchi, and Vincent Sitzmann. 2024. pixelSplat: 3D Gaussian Splats from Image Pairs for Scalable Generalizable 3D Reconstruction. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[27] Anpei Chen, Haofei Xu, Stefano Esposito, Siyu Tang, and Andreas Geiger. 2024. LaRa: Efficient Large-Baseline Radiance Fields. arXiv preprint arXiv:2407.04699 (2024).

[28] Hanlin Chen, Chen Li, and Gim Hee Lee. 2023. NeuSG: Neural Implicit Surface Reconstruction with 3D Gaussian Splatting Guidance. arXiv preprint arXiv:2312.00846 (2023).

[29] Yiwen Chen, Zilong Chen, Chi Zhang, Feng Wang, Xiaofeng Yang, Yikai Wang, Zhongang Cai, Lei Yang, Huaping Liu, and Guosheng Lin. 2024. GaussianEditor: Swift and Controllable 3D Editing with Gaussian Splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[30] Yufan Chen, Lizhen Wang, Qijing Li, Hongjiang Xiao, Shengping Zhang, Hongxun Yao, and Yebin Liu. 2023. MonoGaussianAvatar: Monocular Gaussian Point-based Head Avatar. arXiv preprint arXiv:2312.04558 (2023).

[31] Yihang Chen, Qianyi Wu, Jianfei Cai, Mehrtash Harandi, and Weiyao Lin. 2024. HAC: Hash-grid Assisted Context for 3D Gaussian Splatting Compression. In Proc. Eur. Conf. Comput. Vis.

[32] Yuedong Chen, Haofei Xu, Chuanxia Zheng, Bohan Zhuang, Marc Pollefeys, Andreas Geiger, Tat-Jen Cham, and Jianfei Cai. 2024. MVSplat: Efficient 3D Gaussian Splatting from Sparse Multi-View Images. In Proc. Eur. Conf. Comput. Vis.

[33] Zilong Chen, Feng Wang, and Huaping Liu. 2024. Text-to-3d using gaussian splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[34] Kai Cheng, Xiaoxiao Long, Kaizhi Yang, Yao Yao, Wei Yin, Yuexin Ma, Wenping Wang, and Xuejin Chen. 2024. GaussianPro: 3D Gaussian Splatting with Progressive Propagation. In Proc. ACM Int. Conf. Mach. Learn.

[35] Seokhun Choi, Hyeonseop Song, Jaechul Kim, Taehyeong Kim, and Hoseok Do. 2024. Click-Gaussian: Interactive Segmentation to Any 3D Gaussians. arXiv preprint arXiv:2407.11793 (2024).

[36] Jorge Condor, Sebastien Speierer, Lukas Bode, Aljaz Bozic, Simon Green, Piotr Didyk, and Adrian Jarabo. 2025. Don’t Splat your Gaussians: Volumetric Ray-Traced Primitives for Modeling and Rendering Scattering and Emissive Media. ACM Trans. Graph. (2025).

[37] Daniel Cudeiro, Timo Bolkart, Cassidy Laidlaw, Anurag Ranjan, and Michael J Black. 2019. Capture, learning, and synthesis of 3D speaking styles. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 10101–10111.

[38] Hiba Dahmani, Moussab Bennehar, Nathan Piasco, Luis Roldao, and Dzmitry Tsishkou. 2024. SWAG: Splatting in the Wild images with Appearanceconditioned Gaussians. arXiv preprint arXiv:2403.10427 (2024).

[39] Angela Dai, Angel X Chang, Manolis Savva, Maciej Halber, Thomas Funkhouser, and Matthias Nießner. 2017. Scannet: Richly-annotated 3d reconstructions of indoor scenes. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 5828–5839.

[40] Pinxuan Dai, Jiamin Xu, Wenxiang Xie, Xinguo Liu, Huamin Wang, and Weiwei Xu. 2024. High-quality surface reconstruction using gaussian surfels. In Proc. ACM Spec. Interest Group Comput. Graph. Interact. Tech. 1–11.

Manuscript submitted to ACM

<!-- page 25 of 41 -->

A Survey on 3D Gaussian Splatting

25

[41] Anurag Dalal, Daniel Hagen, Kjell G Robbersmyr, and Kristian Muri Knausgård. 2024. Gaussian Splatting: 3D Reconstruction and Novel View Synthesis, a Review. IEEE Access (2024).

[42] Devikalyan Das, Christopher Wewer, Raza Yunus, Eddy Ilg, and Jan Eric Lenssen. 2024. Neural Parametric Gaussians for Monocular Non-Rigid Object Reconstruction. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[43] Matt Deitke, Dustin Schwenk, Jordi Salvador, Luca Weihs, Oscar Michel, Eli VanderBilt, Ludwig Schmidt, Kiana Ehsani, Aniruddha Kembhavi, and Ali Farhadi. 2023. Objaverse: A universe of annotated 3d objects. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 13142–13153.

[44] Tianchen Deng, Yaohui Chen, Leyan Zhang, Jianfei Yang, Shenghai Yuan, Danwei Wang, and Weidong Chen. 2024. Compact 3d gaussian splatting for dense visual slam. arXiv preprint arXiv:2403.11247 (2024).

[45] Helisa Dhamo, Yinyu Nie, Arthur Moreau, Jifei Song, Richard Shaw, Yiren Zhou, and Eduardo Pérez-Pellitero. 2023. HeadGaS: Real-Time Animatable Head Avatars via 3D Gaussian Splatting. arXiv preprint arXiv:2312.02902 (2023).

[46] Bin Dou, Tianyu Zhang, Yongjia Ma, Zhaohui Wang, and Zejian Yuan. 2024. CoSSegGaussians: Compact and Swift Scene Segmenting 3D Gaussians. arXiv preprint arXiv:2401.05925 (2024).

[47] Yuanxing Duan, Fangyin Wei, Qiyu Dai, Yuhang He, Wenzheng Chen, and Baoquan Chen. 2024. 4d-rotor gaussian splatting: towards efficient novel view synthesis for dynamic scenes. In Proc. ACM Spec. Interest Group Comput. Graph. Interact. Tech. 1–11.

[48] Zhiwen Fan, Kevin Wang, Kairun Wen, Zehao Zhu, Dejia Xu, and Zhangyang Wang. 2023. LightGaussian: Unbounded 3D Gaussian Compression with 15x Reduction and 200+ FPS. arXiv preprint arXiv:2311.17245 (2023).

[49] Guangchi Fang and Bing Wang. 2024. Mini-Splatting: Representing Scenes with a Constrained Number of Gaussians. arXiv preprint arXiv:2403.14166 (2024).

[50] Jiemin Fang, Junjie Wang, Xiaopeng Zhang, Lingxi Xie, and Qi Tian. 2024. Gaussianeditor: Editing 3d gaussians delicately with text instructions. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[51] Jiemin Fang, Taoran Yi, Xinggang Wang, Lingxi Xie, Xiaopeng Zhang, Wenyu Liu, Matthias Nießner, and Qi Tian. 2022. Fast dynamic radiance fields with time-aware neural voxels. In SIGGRAPH Asia. 1–9.

[52] Ben Fei, Jingyi Xu, Rui Zhang, Qingyuan Zhou, Weidong Yang, and Ying He. 2024. 3d gaussian splatting as new era: A survey. IEEE Trans. Vis. Comput. Graph. (2024).

[53] Qijun Feng, Zhen Xing, Zuxuan Wu, and Yu-Gang Jiang. 2024. FDGaussian: Fast Gaussian Splatting from Single Image via Geometric-aware Diffusion Model. arXiv preprint arXiv:2403.10242 (2024).

[54] Tuo Feng, Wenguan Wang, and Yi Yang. 2025. Gaussian-based World Model: Gaussian Priors for Voxel-Based Occupancy Prediction and Future Motion Prediction. In Proc. IEEE Int. Conf. Comput. Vis. 25239–25249.

[55] Yutao Feng, Xiang Feng, Yintong Shang, Ying Jiang, Chang Yu, Zeshun Zong, Tianjia Shao, Hongzhi Wu, Kun Zhou, Chenfanfu Jiang, et al. 2024. Gaussian Splashing: Dynamic Fluid Synthesis with Gaussian Splatting. arXiv preprint arXiv:2401.15318 (2024).

[56] Linus Franke, Darius Rückert, Laura Fink, and Marc Stamminger. 2024. TRIPS: Trilinear Point Splatting for Real-Time Radiance Field Rendering. In Computer Graphics Forum, Vol. 43. e15012.

[57] Sara Fridovich-Keil, Giacomo Meanti, Frederik Rahbæk Warburg, Benjamin Recht, and Angjoo Kanazawa. 2023. K-planes: Explicit radiance fields in space, time, and appearance. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 12479–12488.

[58] Sara Fridovich-Keil, Alex Yu, Matthew Tancik, Qinhong Chen, Benjamin Recht, and Angjoo Kanazawa. 2022. Plenoxels: Radiance fields without neural networks. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 5501–5510.

[59] Yang Fu, Sifei Liu, Amey Kulkarni, Jan Kautz, Alexei A Efros, and Xiaolong Wang. 2024. COLMAP-Free 3D Gaussian Splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[60] Jian Gao, Chun Gu, Youtian Lin, Hao Zhu, Xun Cao, Li Zhang, and Yao Yao. 2023. Relightable 3D Gaussian: Real-time Point Cloud Relighting with BRDF Decomposition and Ray Tracing. arXiv preprint arXiv:2311.16043 (2023).

[61] Jianzhe Gao, Rui Liu, and Wenguan Wang. 2025. 3d gaussian map with open-set semantic grouping for vision-language navigation. In Proc. IEEE Int. Conf. Comput. Vis. 9252–9262.

[62] Jianzhe Gao, Rui Liu, Yuxuan Xu, Tongtong Cao, Yingxue Zhang, Zhanguang Zhang, Sida Peng, Yi Yang, and Wenguan Wang. 2026. Uncertaintyaware gaussian map for vision-language navigation. In Proc. Int. Conf. Learn. Represent.

[63] Lin Gao, Jie Yang, Bo-tao Zhang, Jia-mu Sun, Yu-jie Yuan, Hongbo Fu, and Yu-kun Lai. 2024. Real-time large-scale deformation of gaussian splatting. ACM Trans. Graph. 43, 6 (2024), 1–17.

[64] Stephan J Garbin, Marek Kowalski, Matthew Johnson, Jamie Shotton, and Julien Valentin. 2021. Fastnerf: High-fidelity neural rendering at 200fps. In Proc. IEEE Int. Conf. Comput. Vis. 14346–14355.

[65] Andreas Geiger, Philip Lenz, and Raquel Urtasun. 2012. Are we ready for autonomous driving? the kitti vision benchmark suite. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 3354–3361.

[66] Chen Geng, Sida Peng, Zhen Xu, Hujun Bao, and Xiaowei Zhou. 2023. Learning neural volumetric representations of dynamic humans in minutes. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 8759–8770.

[67] Michael Goesele, Noah Snavely, Brian Curless, Hugues Hoppe, and Steven M Seitz. 2007. Multi-view stereo for community photo collections. In Proc. IEEE Int. Conf. Comput. Vis. 1–8.

[68] Steven J Gortler, Radek Grzeszczuk, Richard Szeliski, and Michael F Cohen. 2023. The lumigraph. In Seminal Graphics Papers: Pushing the Boundaries, Volume 2. 453–464.

Manuscript submitted to ACM

<!-- page 26 of 41 -->

26

Guikun Chen and Wenguan Wang

[69] Jeffrey P Grossman and William J Dally. 1998. Point sample rendering. In Render. Tech. 181–192.

[70] Qiao Gu, Zhaoyang Lv, Duncan Frost, Simon Green, Julian Straub, and Chris Sweeney. 2024. EgoLifter: Open-world 3D Segmentation for Egocentric Perception. arXiv preprint arXiv:2403.18118 (2024).

[71] Antoine Guédon and Vincent Lepetit. 2024. SuGaR: Surface-Aligned Gaussian Splatting for Efficient 3D Mesh Reconstruction and High-Quality Mesh Rendering. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[72] Xiang Guo, Jiadai Sun, Yuchao Dai, Guanying Chen, Xiaoqing Ye, Xiao Tan, Errui Ding, Yumeng Zhang, and Jingdong Wang. 2023. Forward flow for novel view synthesis of dynamic scenes. In Proc. IEEE Int. Conf. Comput. Vis. 16022–16033.

[73] Zhiyang Guo, Wengang Zhou, Li Li, Min Wang, and Houqiang Li. 2024. Motion-aware 3D Gaussian Splatting for Efficient Dynamic Scene Reconstruction. arXiv preprint arXiv:2403.11447 (2024).

[74] Xian-Feng Han, Hamid Laga, and Mohammed Bennamoun. 2019. Image-based 3D object reconstruction: State-of-the-art and trends in the deep learning era. IEEE Trans. Pattern Anal. Mach. Intell. 43, 5 (2019), 1578–1604.

[75] Shuting He, Peilin Ji, Yitong Yang, Changshuo Wang, Jiayi Ji, Yinglin Wang, and Henghui Ding. 2025. A survey on 3d gaussian splatting applications: Segmentation, editing, and generation. arXiv preprint arXiv:2508.09977 (2025).

[76] Xianglong He, Junyi Chen, Sida Peng, Di Huang, Yangguang Li, Xiaoshui Huang, Chun Yuan, Wanli Ouyang, and Tong He. 2024. Gvgen: Text-to-3d generation with volumetric representation. In Proc. Eur. Conf. Comput. Vis.

[77] Peter Hedman, Julien Philip, True Price, Jan-Michael Frahm, George Drettakis, and Gabriel Brostow. 2018. Deep blending for free-viewpoint image-based rendering. ACM Trans. Graph. 37, 6 (2018), 1–15.

[78] Jan Held, Renaud Vandeghen, Abdullah Hamdi, Adrien Deliege, Anthony Cioppa, Silvio Giancola, Andrea Vedaldi, Bernard Ghanem, and Marc Van Droogenbroeck. 2025. 3D convex splatting: Radiance field rendering with 3D smooth convexes. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 21360–21369.

[79] Sheng Hong, Junjie He, Xinhu Zheng, Hesheng Wang, Hao Fang, Kangcheng Liu, Chunran Zheng, and Shaojie Shen. 2024. LIV-GaussMap: LiDAR-Inertial-Visual Fusion for Real-time 3D Radiance Field Map Rendering. arXiv preprint arXiv:2401.14857 (2024).

[80] Jiarui Hu, Xianhao Chen, Boyin Feng, Guanglin Li, Liangjing Yang, Hujun Bao, Guofeng Zhang, and Zhaopeng Cui. 2024. CG-SLAM: Efficient Dense RGB-D SLAM in a Consistent Uncertainty-aware 3D Gaussian Field. arXiv preprint arXiv:2403.16095 (2024).

[81] Liangxiao Hu, Hongwen Zhang, Yuxiang Zhang, Boyao Zhou, Boning Liu, Shengping Zhang, and Liqiang Nie. 2024. GaussianAvatar: Towards Realistic Human Avatar Modeling from a Single Video via Animatable 3D Gaussians. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[82] Shoukang Hu and Ziwei Liu. 2024. GauHuman: Articulated Gaussian Splatting from Monocular Human Videos. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[83] Xu Hu, Yuxi Wang, Lue Fan, Junsong Fan, Junran Peng, Zhen Lei, Qing Li, and Zhaoxiang Zhang. 2024. Semantic Anything in 3D Gaussians. arXiv preprint arXiv:2401.17857 (2024).

[84] Yuanming Hu, Yu Fang, Ziheng Ge, Ziyin Qu, Yixin Zhu, Andre Pradhana, and Chenfanfu Jiang. 2018. A moving least squares material point method with displacement discontinuity and two-way rigid body coupling. ACM Trans. Graph. 37, 4 (2018), 1–14.

[85] Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger, and Shenghua Gao. 2024. 2d gaussian splatting for geometrically accurate radiance fields. In Proc. ACM Spec. Interest Group Comput. Graph. Interact. Tech. 1–11.

[86] Huajian Huang, Longwei Li, Hui Cheng, and Sai-Kit Yeung. 2024. Photo-SLAM: Real-time Simultaneous Localization and Photorealistic Mapping for Monocular, Stereo, and RGB-D Cameras. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[87] Jiajun Huang and Hongchuan Yu. 2023. Point’n Move: Interactive Scene Object Manipulation on Gaussian Splatting Radiance Fields. arXiv preprint arXiv:2311.16737 (2023).

[88] Letian Huang, Jiayang Bai, Jie Guo, and Yanwen Guo. 2024. GS++: Error Analyzing and Optimal Gaussian Splatting. arXiv preprint arXiv:2402.00752 (2024).

[89] Tianyu Huang, Yihan Zeng, Hui Li, Wangmeng Zuo, and Rynson WH Lau. 2025. DreamPhysics: Learning Physical Properties of Dynamic 3D Gaussians with Video Diffusion Priors. In Proc. AAAI Conf. Artif. Intell.

[90] Yiming Huang, Beilei Cui, Long Bai, Ziqi Guo, Mengya Xu, and Hongliang Ren. 2024. Endo-4DGS: Distilling Depth Ranking for Endoscopic Monocular Scene Reconstruction with 4D Gaussian Splatting. In Proc. Int. Conf. Med. Image Comput. Comput. Assist. Interv.

[91] Yi-Hua Huang, Ming-Xian Lin, Yang-Tian Sun, Ziyi Yang, Xiaoyang Lyu, Yan-Pei Cao, and Xiaojuan Qi. 2025. Deformable radial kernel splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 21513–21523.

[92] Yi-Hua Huang, Yang-Tian Sun, Ziyi Yang, Xiaoyang Lyu, Yan-Pei Cao, and Xiaojuan Qi. 2024. SC-GS: Sparse-Controlled Gaussian Splatting for Editable Dynamic Scenes. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[93] Stephen James, Zicong Ma, David Rovick Arrojo, and Andrew J Davison. 2020. Rlbench: The robot learning benchmark & learning environment. IEEE Robotics and Automation Letters 5, 2 (2020), 3019–3026.

[94] Rohit Jena, Ganesh Subramanian Iyer, Siddharth Choudhary, Brandon Smith, Pratik Chaudhari, and James Gee. 2023. SplatArmor: Articulated Gaussian splatting for animatable humans from monocular RGB videos. arXiv preprint arXiv:2311.10812 (2023).

[95] Mazeyu Ji, Ri-Zhao Qiu, Xueyan Zou, and Xiaolong Wang. 2024. GraspSplats: Efficient Manipulation with 3D Feature Splatting. arXiv preprint arXiv:2409.02084 (2024).

[96] Shengxiang Ji, Guanjun Wu, Jiemin Fang, Jiazhong Cen, Taoran Yi, Wenyu Liu, Qi Tian, and Xinggang Wang. 2024. Segment Any 4D Gaussians. arXiv preprint arXiv:2407.04504 (2024).

Manuscript submitted to ACM

<!-- page 27 of 41 -->

A Survey on 3D Gaussian Splatting

27

[97] Yiming Ji, Yang Liu, Guanghu Xie, Boyu Ma, and Zongwu Xie. 2024. NEDS-SLAM: A Novel Neural Explicit Dense Semantic SLAM Framework using 3D Gaussian Splatting. arXiv preprint arXiv:2403.11679 (2024).

[98] Yuzhou Ji, He Zhu, Junshu Tang, Wuyi Liu, Zhizhong Zhang, Yuan Xie, Lizhuang Ma, and Xin Tan. 2024. FastLGS: Speeding up Language Embedded Gaussians with Feature Grid Mapping. arXiv preprint arXiv:2406.01916 (2024).

[99] Lihan Jiang, Yucheng Mao, Linning Xu, Tao Lu, Kerui Ren, Yichen Jin, Xudong Xu, Mulin Yu, Jiangmiao Pang, Feng Zhao, et al. 2025. Anysplat: Feed-forward 3d gaussian splatting from unconstrained views. 44, 6 (2025), 1–16.

[100] Lutao Jiang and Lin Wang. 2024. BrightDreamer: Generic 3D Gaussian Generative Framework for Fast Text-to-3D Synthesis. arXiv preprint arXiv:2403.11273 (2024).

[101] Yuheng Jiang, Zhehao Shen, Penghao Wang, Zhuo Su, Yu Hong, Yingliang Zhang, Jingyi Yu, and Lan Xu. 2024. HiFi4G: High-Fidelity Human Performance Rendering via Compact Gaussian Splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[102] Yingwenqi Jiang, Jiadong Tu, Yuan Liu, Xifeng Gao, Xiaoxiao Long, Wenping Wang, and Yuexin Ma. 2024. GaussianShader: 3D Gaussian Splatting with Shading Functions for Reflective Surfaces. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[103] Ying Jiang, Chang Yu, Tianyi Xie, Xuan Li, Yutao Feng, Huamin Wang, Minchen Li, Henry Lau, Feng Gao, Yin Yang, et al. 2024. VR-GS: A Physical Dynamics-Aware Interactive Gaussian Splatting System in Virtual Reality. arXiv preprint arXiv:2401.16663 (2024).

[104] Mohammad Mahdi Johari, Camilla Carta, and François Fleuret. 2023. Eslam: Efficient dense slam system based on hybrid representation of signed distance fields. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 17408–17419.

[105] HyunJun Jung, Nikolas Brasch, Jifei Song, Eduardo Perez-Pellitero, Yiren Zhou, Zhihao Li, Nassir Navab, and Benjamin Busam. 2023. Deformable 3D Gaussian Splatting for Animatable Human Avatars. arXiv preprint arXiv:2312.15059 (2023).

[106] Jaewoo Jung, Jisang Han, Honggyu An, Jiwon Kang, Seonghoon Park, and Seungryong Kim. 2024. Relaxing Accurate Initialization Constraint for 3D Gaussian Splatting. arXiv preprint arXiv:2403.09413 (2024).

[107] Denis Kalkofen, Erick Mendez, and Dieter Schmalstieg. 2008. Comprehensible visualization for augmented reality. IEEE Trans. Vis. Comput. Graph. 15, 2 (2008), 193–204.

[108] Kacper Kania, Kwang Moo Yi, Marek Kowalski, Tomasz Trzciński, and Andrea Tagliasacchi. 2022. Conerf: Controllable neural radiance fields. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 18623–18632.

[109] Kai Katsumata, Duc Minh Vo, and Hideki Nakayama. 2023. An Efficient 3D Gaussian Representation for Monocular/Multi-view Dynamic Scenes. arXiv preprint arXiv:2311.12897 (2023).

[110] Nikhil Keetha, Jay Karhade, Krishna Murthy Jatavallabhula, Gengshan Yang, Sebastian Scherer, Deva Ramanan, and Jonathon Luiten. 2024. Splatam: Splat, track & map 3d gaussians for dense rgb-d slam. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[111] Bernhard Kerbl, Georgios Kopanas, Thomas Leimkühler, and George Drettakis. 2023. 3D Gaussian Splatting for Real-Time Radiance Field Rendering. ACM Trans. Graph. 42, 4 (2023).

[112] Bernhard Kerbl, Andreas Meuleman, Georgios Kopanas, Michael Wimmer, Alexandre Lanvin, and George Drettakis. 2024. A hierarchical 3d gaussian representation for real-time rendering of very large datasets. ACM Trans. Graph. 44, 3 (2024).

[113] Jaihoon Kim, Juil Koo, Kyeongmin Yeo, and Minhyuk Sung. 2024. SyncTweedies: A General Generative Framework Based on Synchronized Diffusions. arXiv preprint arXiv:2403.14370 (2024).

[114] Arno Knapitsch, Jaesik Park, Qian-Yi Zhou, and Vladlen Koltun. 2017. Tanks and temples: Benchmarking large-scale scene reconstruction. ACM Trans. Graph. 36, 4 (2017), 1–13.

[115] Leif Kobbelt and Mario Botsch. 2004. A survey of point-based techniques in computer graphics. Comput. Graph. 28, 6 (2004), 801–814.

[116] Muhammed Kocabas, Jen-Hao Rick Chang, James Gabriel, Oncel Tuzel, and Anurag Ranjan. 2024. HUGS: Human Gaussian Splats. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[117] Agelos Kratimenos, Jiahui Lei, and Kostas Daniilidis. 2023. DynMF: Neural Motion Factorization for Real-time Dynamic View Synthesis with 3D Gaussian Splatting. arXiv preprint arXiv:2312.00112 (2023).

[118] Youngjoong Kwon, Dahun Kim, Duygu Ceylan, and Henry Fuchs. 2021. Neural human performer: Learning generalizable radiance fields for human performance rendering. In Proc. Adv. Neural Inf. Process. Syst. 24741–24752.

[119] Samuli Laine, Janne Hellsten, Tero Karras, Yeongho Seol, Jaakko Lehtinen, and Timo Aila. 2020. Modular primitives for high-performance differentiable rendering. ACM Trans. Graph. 39, 6 (2020), 1–14.

[120] Kun Lan, Haoran Li, Haolin Shi, Wenjun Wu, Yong Liao, Lin Wang, and Pengyuan Zhou. 2023. 2D-Guided 3D Gaussian Segmentation. arXiv preprint arXiv:2312.16047 (2023).

[121] Xiaolei Lang, Laijian Li, Hang Zhang, Feng Xiong, Mu Xu, Yong Liu, Xingxing Zuo, and Jiajun Lv. 2024. Gaussian-LIC: Photo-realistic LiDAR-Inertial-Camera SLAM with 3D Gaussian Splatting. arXiv preprint arXiv:2404.06926 (2024).

[122] Christoph Lassner and Michael Zollhofer. 2021. Pulsar: Efficient sphere-based neural rendering. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 1440–1449.

[123] Byeonghyeon Lee, Howoong Lee, Xiangyu Sun, Usman Ali, and Eunbyung Park. 2024. Deblurring 3D Gaussian Splatting. arXiv preprint arXiv:2401.00834 (2024).

[124] Joo Chan Lee, Daniel Rho, Xiangyu Sun, Jong Hwan Ko, and Eunbyung Park. 2024. Compact 3D Gaussian Representation for Radiance Field. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

Manuscript submitted to ACM

<!-- page 28 of 41 -->

Manuscript submitted to ACM

28

Guikun Chen and Wenguan Wang

[125] Yao-Chih Lee, Yi-Ting Chen, Andrew Wang, Ting-Hsuan Liao, Brandon Y Feng, and Jia-Bin Huang. 2024. VividDream: Generating 3D Scene with Ambient Dynamics. arXiv preprint arXiv:2405.20334 (2024).

[126] Jiahui Lei, Yufu Wang, Georgios Pavlakos, Lingjie Liu, and Kostas Daniilidis. 2024. Gart: Gaussian articulated template models. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[127] Jiahui Lei, Yijia Weng, Adam Harley, Leonidas Guibas, and Kostas Daniilidis. 2024. MoSca: Dynamic Gaussian Fusion from Casual Videos via 4D Motion Scaffolds. arXiv preprint arXiv:2405.17421 (2024).

[128] Marc Levoy and Pat Hanrahan. 2023. Light field rendering. In Seminal Graphics Papers: Pushing the Boundaries, Volume 2. 441–452.

[129] Hao Li, Yuanyuan Gao, Dingwen Zhang, Chenming Wu, Yalun Dai, Chen Zhao, Haocheng Feng, Errui Ding, Jingdong Wang, and Junwei Han. 2024. GGRt: Towards Generalizable 3D Gaussians without Pose Priors in Real-Time. arXiv preprint arXiv:2403.10147 (2024).

[130] Haolin Li, Jinyang Liu, Mario Sznaier, and Octavia Camps. 2025. 3d-hgs: 3d half-gaussian splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 10996–11005.

[131] Haoran Li, Haolin Shi, Wenli Zhang, Wenjun Wu, Yong Liao, Lin Wang, Lik-hang Lee, and Pengyuan Zhou. 2024. DreamScene: 3D Gaussian-based Text-to-3D Scene Generation via Formation Pattern Sampling. arXiv preprint arXiv:2404.03575 (2024).

[132] Jiyang Li, Lechao Cheng, Zhangye Wang, Tingting Mu, and Jingxuan He. 2024. LoopGaussian: Creating 3D Cinemagraph with Multi-view Images via Eulerian Motion Field. arXiv preprint arXiv:2404.08966 (2024).

[133] Jiahe Li, Jiawei Zhang, Xiao Bai, Jin Zheng, Xin Ning, Jun Zhou, and Lin Gu. 2024. DNGaussian: Optimizing Sparse-View 3D Gaussian Radiance Fields with Global-Local Depth Normalization. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[134] Jiahe Li, Jiawei Zhang, Xiao Bai, Jin Zheng, Xin Ning, Jun Zhou, and Lin Gu. 2024. TalkingGaussian: Structure-Persistent 3D Talking Head Synthesis via Gaussian Splatting. In Proc. Eur. Conf. Comput. Vis.

[135] Mingrui Li, Shuhong Liu, and Heng Zhou. 2024. SGS-SLAM: Semantic Gaussian Splatting For Neural Dense SLAM. In Proc. Eur. Conf. Comput. Vis.

[136] Mingwei Li, Jiachen Tao, Zongxin Yang, and Yi Yang. 2023. Human101: Training 100+ FPS Human Gaussians in 100s from 1 View. arXiv preprint arXiv:2312.15258 (2023).

[137] Mengtian Li, Shengxiang Yao, Zhifeng Xie, Keyu Chen, and Yu-Gang Jiang. 2024. GaussianBody: Clothed Human Reconstruction via 3d Gaussian Splatting. arXiv preprint arXiv:2401.09720 (2024).

[138] Yingtai Li, Xueming Fu, Shang Zhao, Ruiyang Jin, and S Kevin Zhou. 2023. Sparse-view ct reconstruction with 3d gaussian volumetric representation. arXiv preprint arXiv:2312.15676 (2023).

[139] Yanyan Li, Chenyu Lyu, Yan Di, Guangyao Zhai, Gim Hee Lee, and Federico Tombari. 2024. GeoGaussian: Geometry-aware Gaussian Splatting for Scene Rendering. arXiv preprint arXiv:2403.11324 (2024).

[140] Zhiqi Li, Yiming Chen, Lingzhe Zhao, and Peidong Liu. 2024. Controllable Text-to-3D Generation via Surface-Aligned Gaussian Splatting. arXiv preprint arXiv:2403.09981 (2024).

[141] Zhan Li, Zhang Chen, Zhong Li, and Yi Xu. 2024. Spacetime Gaussian Feature Splatting for Real-Time Dynamic View Synthesis. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[142] Zhe Li, Zerong Zheng, Lizhen Wang, and Yebin Liu. 2024. Animatable Gaussians: Learning Pose-dependent Gaussian Maps for High-fidelity Human Avatar Modeling. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[143] Yiqing Liang, Numair Khan, Zhengqin Li, Thu Nguyen-Phuoc, Douglas Lanman, James Tompkin, and Lei Xiao. 2023. GauFRe: Gaussian Deformation Fields for Real-time Dynamic Novel View Synthesis. arXiv preprint arXiv:2312.11458 (2023).

[144] Yixun Liang, Xin Yang, Jiantao Lin, Haodong Li, Xiaogang Xu, and Yingcong Chen. 2024. LucidDreamer: Towards High-Fidelity Text-to-3D Generation via Interval Score Matching. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[145] Zhihao Liang, Qi Zhang, Wenbo Hu, Ying Feng, Lei Zhu, and Kui Jia. 2024. Analytic-Splatting: Anti-Aliased 3D Gaussian Splatting via Analytic Integration. arXiv preprint arXiv:2403.11056 (2024).

[146] Guibiao Liao, Jiankun Li, Zhenyu Bao, Xiaoqing Ye, Jingdong Wang, Qing Li, and Kanglin Liu. 2024. CLIP-GS: CLIP-Informed Gaussian Splatting for Real-time and View-consistent 3D Semantic Understanding. arXiv preprint arXiv:2404.14249 (2024).

[147] Jiaqi Lin, Zhihao Li, Xiao Tang, Jianzhuang Liu, Shiyong Liu, Jiayue Liu, Yangdi Lu, Xiaofei Wu, Songcen Xu, Youliang Yan, et al. 2024. VastGaussian: Vast 3D Gaussians for Large Scene Reconstruction. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[148] Youtian Lin, Zuozhuo Dai, Siyu Zhu, and Yao Yao. 2024. Gaussian-Flow: 4D Reconstruction with Dynamic 3D Gaussian Particle. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[149] Huan Ling, Seung Wook Kim, Antonio Torralba, Sanja Fidler, and Karsten Kreis. 2024. Align Your Gaussians: Text-to-4D with Dynamic 3D Gaussians and Composed Diffusion Models. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[150] Andrew Liu, Richard Tucker, Varun Jampani, Ameesh Makadia, Noah Snavely, and Angjoo Kanazawa. 2021. Infinite nature: Perpetual view generation of natural scenes from a single image. In Proc. IEEE Int. Conf. Comput. Vis. 14458–14467.

[151] Fangfu Liu, Hanyang Wang, Shunyu Yao, Shengjun Zhang, Jie Zhou, and Yueqi Duan. 2024. Physics3D: Learning Physical Properties of 3D Gaussians via Video Diffusion. arXiv preprint arXiv:2406.04338 (2024).

[152] Rong Liu, Zhongpai Gao, Benjamin Planche, Meida Chen, Van Nguyen Nguyen, Meng Zheng, Anwesa Choudhuri, Terrence Chen, Yue Wang, Andrew Feng, et al. 2025. Universal Beta Splatting. arXiv preprint arXiv:2510.03312 (2025).

[153] Rong Liu, Dylan Sun, Meida Chen, Yue Wang, and Andrew Feng. 2025. Deformable beta splatting. In Proc. ACM Spec. Interest Group Comput. Graph. Interact. Tech. 1–11.

<!-- page 29 of 41 -->

A Survey on 3D Gaussian Splatting

29

[154] Tianqi Liu, Guangcong Wang, Shoukang Hu, Liao Shen, Xinyi Ye, Yuhang Zang, Zhiguo Cao, Wei Li, and Ziwei Liu. 2024. Fast Generalizable Gaussian Splatting Reconstruction from Multi-View Stereo. In Proc. Eur. Conf. Comput. Vis.

[155] Xian Liu, Xiaohang Zhan, Jiaxiang Tang, Ying Shan, Gang Zeng, Dahua Lin, Xihui Liu, and Ziwei Liu. 2024. HumanGaussian: Text-Driven 3D Human Generation with Gaussian Splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[156] Yang Liu, He Guan, Chuanchen Luo, Lue Fan, Junran Peng, and Zhaoxiang Zhang. 2024. CityGaussian: Real-time High-quality Large-Scale Scene Rendering with Gaussians. In Proc. Eur. Conf. Comput. Vis.

[157] Yifan Liu, Chenxin Li, Chen Yang, and Yixuan Yuan. 2024. EndoGaussian: Gaussian Splatting for Deformable Surgical Scene Reconstruction. arXiv preprint arXiv:2401.12561 (2024).

[158] Zhiheng Liu, Hao Ouyang, Qiuyu Wang, Ka Leong Cheng, Jie Xiao, Kai Zhu, Nan Xue, Yu Liu, Yujun Shen, and Yang Cao. 2024. InFusion: Inpainting 3D Gaussians via Learning Depth Completion from Diffusion Prior. arXiv preprint arXiv:2404.11613 (2024).

[159] Guanxing Lu, Shiyi Zhang, Ziwei Wang, Changliu Liu, Jiwen Lu, and Yansong Tang. 2024. ManiGaussian: Dynamic Gaussian Splatting for Multi-task Robotic Manipulation. arXiv preprint arXiv:2403.08321 (2024).

[160] Tao Lu, Mulin Yu, Linning Xu, Yuanbo Xiangli, Limin Wang, Dahua Lin, and Bo Dai. 2024. Scaffold-GS: Structured 3D Gaussians for View-Adaptive Rendering. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[161] Zhicheng Lu, Xiang Guo, Le Hui, Tianrui Chen, Min Yang, Xiao Tang, Feng Zhu, and Yuchao Dai. 2024. 3d geometry-aware deformable gaussian splatting for dynamic view synthesis. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[162] Jonathon Luiten, Georgios Kopanas, Bastian Leibe, and Deva Ramanan. 2024. Dynamic 3d gaussians: Tracking by persistent dynamic view synthesis. In Proc. Int. Conf. 3D Vis.

[163] Haimin Luo, Min Ouyang, Zijun Zhao, Suyi Jiang, Longwen Zhang, Qixuan Zhang, Wei Yang, Lan Xu, and Jingyi Yu. 2024. GaussianHair: Hair Modeling and Rendering with Light-aware Gaussians. arXiv preprint arXiv:2402.10483 (2024).

[164] Weijie Lyu, Xueting Li, Abhijit Kundu, Yi-Hsuan Tsai, and Ming-Hsuan Yang. 2024. Gaga: Group Any Gaussians via 3D-aware Memory Bank. arXiv preprint arXiv:2404.07977 (2024).

[165] Ziqiao Ma, Xuweiyi Chen, Shoubin Yu, Sai Bi, Kai Zhang, Chen Ziwen, Sihan Xu, Jianing Yang, Zexiang Xu, Kalyan Sunkavalli, et al. 2025. 4d-lrm: Large space-time reconstruction model from and to any view at any time. arXiv preprint arXiv:2506.18890 (2025).

[166] Alexander Mai, Peter Hedman, George Kopanas, Dor Verbin, David Futschik, Qiangeng Xu, Falko Kuester, Jonathan T Barron, and Yinda Zhang. 2024. Ever: Exact volumetric ellipsoid rendering for real-time view synthesis. arXiv preprint arXiv:2410.01804 (2024).

[167] Ajay Mandlekar, Danfei Xu, Josiah Wong, Soroush Nasiriany, Chen Wang, Rohun Kulkarni, Li Fei-Fei, Silvio Savarese, Yuke Zhu, and Roberto Martín-Martín. 2022. What Matters in Learning from Offline Human Demonstrations for Robot Manipulation. In Proc. Annu. Conf. Robot Learn. 1678–1690.

[168] Hidenobu Matsuki, Riku Murai, Paul HJ Kelly, and Andrew J Davison. 2024. Gaussian Splatting SLAM. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[169] Morgan McGuire and Louis Bavoil. 2013. Weighted blended order-independent transparency. Journal of Computer Graphics Techniques 2, 4 (2013).

[170] Luke Melas-Kyriazi, Iro Laina, Christian Rupprecht, Natalia Neverova, Andrea Vedaldi, Oran Gafni, and Filippos Kokkinos. 2024. IM-3D: Iterative Multiview Diffusion and Reconstruction for High-Quality 3D Generation. In Proc. ACM Int. Conf. Mach. Learn.

[171] Jiarui Meng, Haijie Li, Yanmin Wu, Qiankun Gao, Shuzhou Yang, Jian Zhang, and Siwei Ma. 2024. Mirror-3dgs: Incorporating mirror reflections into 3d gaussian splatting. arXiv preprint arXiv:2404.01168 (2024).

[172] Lars Mescheder, Michael Oechsle, Michael Niemeyer, Sebastian Nowozin, and Andreas Geiger. 2019. Occupancy networks: Learning 3d reconstruction in function space. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 4460–4470.

[173] Ben Mildenhall, Pratul P Srinivasan, Rodrigo Ortiz-Cayon, Nima Khademi Kalantari, Ravi Ramamoorthi, Ren Ng, and Abhishek Kar. 2019. Local light field fusion: Practical view synthesis with prescriptive sampling guidelines. ACM Trans. Graph. 38, 4 (2019), 1–14.

[174] Ben Mildenhall, Pratul P Srinivasan, Matthew Tancik, Jonathan T Barron, Ravi Ramamoorthi, and Ren Ng. 2020. NeRF: Representing Scenes as Neural Radiance Fields for View Synthesis. In Proc. Eur. Conf. Comput. Vis. 405–421.

[175] Ashkan Mirzaei, Tristan Aumentado-Armstrong, Konstantinos G Derpanis, Jonathan Kelly, Marcus A Brubaker, Igor Gilitschenski, and Alex Levinshtein. 2023. SPIn-NeRF: Multiview segmentation and perceptual inpainting with neural radiance fields. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 20669–20679.

[176] Nicolas Moenne-Loccoz, Ashkan Mirzaei, Or Perel, Riccardo de Lutio, Janick Martinez Esturo, Gavriel State, Sanja Fidler, Nicholas Sharp, and Zan Gojcic. 2024. 3D Gaussian Ray Tracing: Fast Tracing of Particle Scenes. ACM Trans. Graph. 43, 6 (2024), 1–19.

[177] Arthur Moreau, Jifei Song, Helisa Dhamo, Richard Shaw, Yiren Zhou, and Eduardo Pérez-Pellitero. 2024. Human Gaussian Splatting: Real-time Rendering of Animatable Avatars. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[178] Wieland Morgenstern, Florian Barthel, Anna Hilsmann, and Peter Eisert. 2023. Compact 3D Scene Representation via Self-Organizing Gaussian Grids. arXiv preprint arXiv:2312.13299 (2023).

[179] Yuxuan Mu, Xinxin Zuo, Chuan Guo, Yilin Wang, Juwei Lu, Xiaofeng Wu, Songcen Xu, Peng Dai, Youliang Yan, and Li Cheng. 2024. GSD: View-Guided Gaussian Splatting Diffusion for 3D Reconstruction. In Proc. Eur. Conf. Comput. Vis.

[180] Matthias Müller, Bruno Heidelberger, Marcus Hennix, and John Ratcliff. 2007. Position based dynamics. Journal of Visual Communication and Image Representation 18, 2 (2007), 109–118.

Manuscript submitted to ACM

<!-- page 30 of 41 -->

30

Guikun Chen and Wenguan Wang

[181] Thomas Müller, Alex Evans, Christoph Schied, and Alexander Keller. 2022. Instant neural graphics primitives with a multiresolution hash encoding. ACM Trans. Graph. 41, 4 (2022), 1–15.

[182] KL Navaneet, Kossar Pourahmadi Meibodi, Soroush Abbasi Koohpayegani, and Hamed Pirsiavash. 2023. Compact3D: Compressing Gaussian Splat Radiance Field Models with Vector Quantization. arXiv preprint arXiv:2311.18159 (2023).

[183] Simon Niedermayr, Josef Stumpfegger, and Rüdiger Westermann. 2024. Compressed 3d gaussian splatting for accelerated novel view synthesis. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[184] Francesco Palandra, Andrea Sanchietti, Daniele Baieri, and Emanuele Rodolà. 2024. GSEdit: Efficient Text-Guided Editing of 3D Objects via Gaussian Splatting. arXiv preprint arXiv:2403.05154 (2024).

[185] Panwang Pan, Zhuo Su, Chenguo Lin, Zhen Fan, Yongjie Zhang, Zeming Li, Tingting Shen, Yadong Mu, and Yebin Liu. 2024. Humansplat: Generalizable single-image human gaussian splatting with structure priors. In Proc. Adv. Neural Inf. Process. Syst. 74383–74410.

[186] Zijie Pan, Zeyu Yang, Xiatian Zhu, and Li Zhang. 2024. Fast Dynamic 3D Object Generation from a Single-view Video. arXiv preprint arXiv:2401.08742 (2024).

[187] Haokai Pang, Heming Zhu, Adam Kortylewski, Christian Theobalt, and Marc Habermann. 2024. ASH: Animatable Gaussian Splats for Efficient and Photoreal Human Rendering. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[188] Panagiotis Papantonakis, Georgios Kopanas, Bernhard Kerbl, Alexandre Lanvin, and George Drettakis. 2024. Reducing the Memory Footprint of 3D Gaussian Splatting. In I3D. 1–17.

[189] Jeong Joon Park, Peter Florence, Julian Straub, Richard Newcombe, and Steven Lovegrove. 2019. Deepsdf: Learning continuous signed distance functions for shape representation. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 165–174.

[190] Keunhong Park, Utkarsh Sinha, Jonathan T Barron, Sofien Bouaziz, Dan B Goldman, Steven M Seitz, and Ricardo Martin-Brualla. 2021. Nerfies: Deformable neural radiance fields. In Proc. IEEE Int. Conf. Comput. Vis. 5865–5874.

[191] Keunhong Park, Utkarsh Sinha, Peter Hedman, Jonathan T Barron, Sofien Bouaziz, Dan B Goldman, Ricardo Martin-Brualla, and Steven M Seitz. 2021. HyperNeRF: a higher-dimensional representation for topologically varying neural radiance fields. ACM Trans. Graph. 40, 6 (2021), 1–12.

[192] Anjul Patney, Marco Salvi, Joohwan Kim, Anton Kaplanyan, Chris Wyman, Nir Benty, David Luebke, and Aaron Lefohn. 2016. Towards foveated rendering for gaze-tracked virtual reality. ACM Trans. Graph. 35, 6 (2016), 1–12.

[193] Cheng Peng, Yutao Tang, Yifan Zhou, Nengyu Wang, Xijun Liu, Deming Li, and Rama Chellappa. 2024. BAGS: Blur Agnostic Gaussian Splatting through Multi-Scale Kernel Modeling. arXiv preprint arXiv:2403.04926 (2024).

[194] Sida Peng, Junting Dong, Qianqian Wang, Shangzhan Zhang, Qing Shuai, Xiaowei Zhou, and Hujun Bao. 2021. Animatable neural radiance fields for modeling dynamic human bodies. In Proc. IEEE Int. Conf. Comput. Vis. 14314–14323.

[195] Sida Peng, Yuanqing Zhang, Yinghao Xu, Qianqian Wang, Qing Shuai, Hujun Bao, and Xiaowei Zhou. 2021. Neural body: Implicit neural representations with structured latent codes for novel view synthesis of dynamic humans. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 9054–9063.

[196] Zhexi Peng, Tianjia Shao, Yong Liu, Jingke Zhou, Yin Yang, Jingdong Wang, and Kun Zhou. 2024. RTG-SLAM: Real-time 3D Reconstruction at Scale using Gaussian Splatting. ACM Trans. Graph. (2024).

[197] Hanspeter Pfister, Matthias Zwicker, Jeroen Van Baar, and Markus Gross. 2000. Surfels: Surface elements as rendering primitives. In Proceedings of the 27th annual conference on Computer graphics and interactive techniques. 335–342.

[198] Thomas Porter and Tom Duff. 1984. Compositing digital images. In Computer graphics and interactive techniques. 253–259.

[199] Albert Pumarola, Enric Corona, Gerard Pons-Moll, and Francesc Moreno-Noguer. 2021. D-nerf: Neural radiance fields for dynamic scenes. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 10318–10327.

[200] Shenhan Qian, Tobias Kirschstein, Liam Schoneveld, Davide Davoli, Simon Giebenhain, and Matthias Nießner. 2024. GaussianAvatars: Photorealistic Head Avatars with Rigged 3D Gaussians. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[201] Zhiyin Qian, Shaofei Wang, Marko Mihajlovic, Andreas Geiger, and Siyu Tang. 2024. 3DGS-Avatar: Animatable Avatars via Deformable 3D Gaussian Splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[202] Minghan Qin, Wanhua Li, Jiawei Zhou, Haoqian Wang, and Hanspeter Pfister. 2024. LangSplat: 3D Language Gaussian Splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[203] Ri-Zhao Qiu, Ge Yang, Weijia Zeng, and Xiaolong Wang. 2024. Feature Splatting: Language-Driven Physics-Based Scene Synthesis and Editing. arXiv preprint arXiv:2404.01223 (2024).

[204] Yansong Qu, Shaohui Dai, Xinyang Li, Jianghang Lin, Liujuan Cao, Shengchuan Zhang, and Rongrong Ji. 2024. GOI: Find 3D Gaussians of Interest with an Optimizable Open-vocabulary Semantic-space Hyperplane. arXiv preprint arXiv:2405.17596 (2024).

[205] Lukas Radl, Michael Steiner, Mathias Parger, Alexander Weinrauch, Bernhard Kerbl, and Markus Steinberger. 2024. StopThePop: Sorted Gaussian Splatting for View-Consistent Real-time Rendering. ACM Trans. Graph. (2024).

[206] Eduard Ramon, Gil Triginer, Janna Escur, Albert Pumarola, Jaime Garcia, Xavier Giro-i Nieto, and Francesc Moreno-Noguer. 2021. H3d-net: Few-shot high-fidelity 3d head reconstruction. In Proc. IEEE Int. Conf. Comput. Vis. 5620–5629.

[207] Jiawei Ren, Liang Pan, Jiaxiang Tang, Chi Zhang, Ang Cao, Gao Zeng, and Ziwei Liu. 2023. DreamGaussian4D: Generative 4D Gaussian Splatting. arXiv preprint arXiv:2312.17142 (2023).

[208] Jiawei Ren, Kevin Xie, Ashkan Mirzaei, Hanxue Liang, Xiaohui Zeng, Karsten Kreis, Ziwei Liu, Antonio Torralba, Sanja Fidler, Seung W Kim, et al. 2024. L4gm: Large 4d gaussian reconstruction model. In Proc. Adv. Neural Inf. Process. Syst. 56828–56858.

Manuscript submitted to ACM

<!-- page 31 of 41 -->

A Survey on 3D Gaussian Splatting

31

[209] Kerui Ren, Lihan Jiang, Tao Lu, Mulin Yu, Linning Xu, Zhangkai Ni, and Bo Dai. 2024. Octree-gs: Towards consistent real-time rendering with lod-structured 3d gaussians. arXiv preprint arXiv:2403.17898 (2024).

[210] Liu Ren, Hanspeter Pfister, and Matthias Zwicker. 2002. Object space EWA surface splatting: A hardware accelerated approach to high quality point rendering. In Comput. Graph. Forum. 461–470.

[211] Alfredo Rivero, ShahRukh Athar, Zhixin Shu, and Dimitris Samaras. 2024. Rig3DGS: Creating Controllable Portraits from Casual Monocular Videos. arXiv preprint arXiv:2402.03723 (2024).

[212] Darius Rückert, Linus Franke, and Marc Stamminger. 2022. Adop: Approximate differentiable one-pixel point rendering. ACM Trans. Graph. 41, 4 (2022), 1–14.

[213] Szymon Rusinkiewicz and Marc Levoy. 2000. QSplat: A multiresolution point rendering system for large meshes. In Computer graphics and interactive techniques. 343–352.

[214] Shunsuke Saito, Gabriel Schwartz, Tomas Simon, Junxuan Li, and Giljoo Nam. 2024. Relightable Gaussian Codec Avatars. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[215] Erik Sandström, Yue Li, Luc Van Gool, and Martin R Oswald. 2023. Point-slam: Dense neural point cloud-based slam. In Proc. IEEE Int. Conf. Comput. Vis. 18433–18444.

[216] Erik Sandström, Keisuke Tateno, Michael Oechsle, Michael Niemeyer, Luc Van Gool, Martin R Oswald, and Federico Tombari. 2024. Splat-SLAM: Globally Optimized RGB-only SLAM with 3D Gaussians. arXiv preprint arXiv:2405.16544 (2024).

[217] Kyle Sargent, Zizhang Li, Tanmay Shah, Charles Herrmann, Hong-Xing Yu, Yunzhi Zhang, Eric Ryan Chan, Dmitry Lagun, Li Fei-Fei, Deqing Sun, et al. 2024. ZeroNVS: Zero-Shot 360-Degree View Synthesis from a Single Image. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 9420–9429.

[218] Abhishek Saroha, Mariia Gladkova, Cecilia Curreli, Tarun Yenamandra, and Daniel Cremers. 2024. Gaussian Splatting in Style. arXiv preprint arXiv:2403.08498 (2024).

[219] Johannes L Schonberger and Jan-Michael Frahm. 2016. Structure-from-motion revisited. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 4104–4113.

[221] Ruizhi Shao, Jingxiang Sun, Cheng Peng, Zerong Zheng, Boyao Zhou, Hongwen Zhang, and Yebin Liu. 2024. Control4D: Efficient 4D Portrait Editing with Text. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[222] Ruizhi Shao, Zerong Zheng, Hanzhang Tu, Boning Liu, Hongwen Zhang, and Yebin Liu. 2023. Tensor4d: Efficient neural 4d decomposition for high-fidelity dynamic reconstruction and rendering. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 16632–16642.

[223] Yidi Shao, Mu Huang, Chen Change Loy, and Bo Dai. 2024. GauSim: Registering Elastic Objects into Digital World by Gaussian Simulator. arXiv preprint arXiv:2412.17804 (2024).

[224] Richard Shaw, Jifei Song, Arthur Moreau, Michal Nazarczuk, Sibi Catley-Chandar, Helisa Dhamo, and Eduardo Perez-Pellitero. 2023. SWAGS: Sampling Windows Adaptively for Dynamic 3D Gaussian Splatting. arXiv preprint arXiv:2312.13308 (2023).

[225] Qiuhong Shen, Xuanyu Yi, Zike Wu, Pan Zhou, Hanwang Zhang, Shuicheng Yan, and Xinchao Wang. 2024. Gamba: Marry Gaussian Splatting with Mamba for single view 3D reconstruction. arXiv preprint arXiv:2403.18795 (2024).

[226] Jin-Chuan Shi, Miao Wang, Hao-Bin Duan, and Shao-Hua Guan. 2024. Language Embedded 3D Gaussians for Open-Vocabulary Scene Understanding. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[227] Olaolu Shorinwa, Johnathan Tucker, Aliyah Smith, Aiden Swann, Timothy Chen, Roya Firoozi, Monroe David Kennedy, and Mac Schwager. 2024. Splat-MOVER: Multi-Stage, Open-Vocabulary Robotic Manipulation via Editable Gaussian Splatting. In Proc. Annu. Conf. Robot Learn.

[228] Vincent Sitzmann, Justus Thies, Felix Heide, Matthias Nießner, Gordon Wetzstein, and Michael Zollhofer. 2019. Deepvoxels: Learning persistent 3d feature embeddings. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 2437–2446.

[229] Cameron Smith, David Charatan, Ayush Tewari, and Vincent Sitzmann. 2024. FlowMap: High-Quality Camera Poses, Intrinsics, and Depth via Gradient Descent. arXiv preprint arXiv:2404.15259 (2024).

[230] Noah Snavely, Steven M Seitz, and Richard Szeliski. 2006. Photo tourism: exploring photo collections in 3D. In ACM Trans. Graph. 835–846.

[231] Xiaowei Song, Jv Zheng, Shiran Yuan, Huan-ang Gao, Jingwei Zhao, Xiang He, Weihao Gu, and Hao Zhao. 2024. SA-GS: Scale-Adaptive Gaussian Splatting for Training-Free Anti-Aliasing. arXiv preprint arXiv:2403.19615 (2024).

[232] Julian Straub, Thomas Whelan, Lingni Ma, Yufan Chen, Erik Wijmans, Simon Green, Jakob J Engel, Raul Mur-Artal, Carl Ren, Shobhit Verma, et al. 2019. The Replica dataset: A digital replica of indoor spaces. arXiv preprint arXiv:1906.05797 (2019).

[233] Jürgen Sturm, Nikolas Engelhard, Felix Endres, Wolfram Burgard, and Daniel Cremers. 2012. A benchmark for the evaluation of RGB-D SLAM systems. In Proc. IEEE/RSJ Int. Conf. Intell. Robot. Syst. 573–580.

[234] Zhaoqi Su, Tao Yu, Yangang Wang, and Yebin Liu. 2022. Deepcloth: Neural garment representation for shape and style editing. IEEE Trans. Pattern Anal. Mach. Intell. 45, 2 (2022), 1581–1593.

[235] Edgar Sucar, Shikun Liu, Joseph Ortiz, and Andrew J Davison. 2021. iMAP: Implicit mapping and positioning in real-time. In Proc. IEEE Int. Conf. Comput. Vis. 6229–6238.

[236] Cheng Sun, Min Sun, and Hwann-Tzong Chen. 2022. Direct voxel grid optimization: Super-fast convergence for radiance fields reconstruction. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 5459–5469.

[237] Pei Sun, Henrik Kretzschmar, Xerxes Dotiwalla, Aurelien Chouard, Vijaysai Patnaik, Paul Tsui, James Guo, Yin Zhou, Yuning Chai, Benjamin Caine, et al. 2020. Scalability in perception for autonomous driving: Waymo open dataset. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 2446–2454.

Manuscript submitted to ACM

<!-- page 32 of 41 -->

32

Guikun Chen and Wenguan Wang

[238] Shuo Sun, Malcolm Mielle, Achim J Lilienthal, and Martin Magnusson. 2024. High-Fidelity SLAM Using Gaussian Splatting with Rendering-Guided Densification and Regularized Optimization. In Proc. IEEE/RSJ Int. Conf. Intell. Robot. Syst.

[239] Aiden Swann, Matthew Strong, Won Kyung Do, Gadiel Sznaier Camps, Mac Schwager, and Monroe Kennedy III. 2024. Touch-GS: Visual-Tactile Supervised 3D Gaussian Splatting. arXiv preprint arXiv:2403.09875 (2024).

[240] Stanislaw Szymanowicz, Eldar Insafutdinov, Chuanxia Zheng, Dylan Campbell, João F Henriques, Christian Rupprecht, and Andrea Vedaldi. 2024. Flash3D: Feed-Forward Generalisable 3D Scene Reconstruction from a Single Image. arXiv preprint arXiv:2406.04343 (2024).

[241] Stanislaw Szymanowicz, Christian Rupprecht, and Andrea Vedaldi. 2024. Splatter Image: Ultra-Fast Single-View 3D Reconstruction. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[242] Matthew Tancik, Vincent Casser, Xinchen Yan, Sabeek Pradhan, Ben Mildenhall, Pratul P Srinivasan, Jonathan T Barron, and Henrik Kretzschmar. 2022. Block-nerf: Scalable large scene neural view synthesis. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 8248–8258.

[243] Jiaxiang Tang, Zhaoxi Chen, Xiaokang Chen, Tengfei Wang, Gang Zeng, and Ziwei Liu. 2024. LGM: Large Multi-View Gaussian Model for High-Resolution 3D Content Creation. In Proc. Eur. Conf. Comput. Vis.

[244] Jiaxiang Tang, Jiawei Ren, Hang Zhou, Ziwei Liu, and Gang Zeng. 2024. Dreamgaussian: Generative gaussian splatting for efficient 3d content creation. In Proc. Int. Conf. Learn. Represent.

[245] Ayush Tewari, Justus Thies, Ben Mildenhall, Pratul Srinivasan, Edgar Tretschk, Wang Yifan, Christoph Lassner, Vincent Sitzmann, Ricardo Martin-Brualla, Stephen Lombardi, et al. 2022. Advances in neural rendering. In Comput. Graph. Forum. 703–735.

[246] Fabio Tosi, Youmin Zhang, Ziren Gong, Erik Sandström, Stefano Mattoccia, Martin R Oswald, and Matteo Poggi. 2024. How NeRFs and 3D Gaussian Splatting are Reshaping SLAM: a Survey. arXiv preprint arXiv:2402.13255 (2024).

[247] Evangelos Ververas, Rolandos Alexandros Potamias, Jifei Song, Jiankang Deng, and Stefanos Zafeiriou. 2024. Sags: Structure-aware 3d gaussian splatting. In Proc. Eur. Conf. Comput. Vis. 221–238.

[248] Joanna Waczyńska, Piotr Borycki, Sławomir Tadeja, Jacek Tabor, and Przemysław Spurek. 2024. Games: Mesh-based adapting and modification of gaussian splatting. arXiv preprint arXiv:2402.01459 (2024).

[249] Chen Wang, Hao Tan, Wang Yifan, Zhiqin Chen, Yuheng Liu, Kalyan Sunkavalli, Sai Bi, Lingjie Liu, and Yiwei Hu. 2026. tttLRM: Test-Time Training for Long Context and Autoregressive 3D Reconstruction. arXiv preprint arXiv:2602.20160 (2026).

[250] Feng Wang, Zilong Chen, Guokang Wang, Yafei Song, and Huaping Liu. 2023. Masked Space-Time Hash Encoding for Efficient Dynamic Scene Reconstruction. In Proc. Adv. Neural Inf. Process. Syst.

[251] Hengyi Wang, Jingwen Wang, and Lourdes Agapito. 2023. Co-SLAM: Joint Coordinate and Sparse Parametric Encodings for Neural Real-Time SLAM. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 13293–13302.

[252] Jianyuan Wang, Minghao Chen, Nikita Karaev, Andrea Vedaldi, Christian Rupprecht, and David Novotny. 2025. Vggt: Visual geometry grounded transformer. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 5294–5306.

[253] Jiaxu Wang, Ziyi Zhang, Qiang Zhang, Jia Li, Jingkai Sun, Mingyuan Sun, Junhao He, and Renjing Xu. 2024. Query-based Semantic Gaussian Field for Scene Representation in Reinforcement Learning. arXiv preprint arXiv:2406.02370 (2024).

[254] Kailing Wang, Chen Yang, Yuehao Wang, Sikuang Li, Yan Wang, Qi Dou, Xiaokang Yang, and Wei Shen. 2024. EndoGSLAM: Real-Time Dense Reconstruction and Tracking in Endoscopic Surgeries using Gaussian Splatting. arXiv preprint arXiv:2403.15124 (2024).

[255] Qianqian Wang, Vickie Ye, Hang Gao, Jake Austin, Zhengqi Li, and Angjoo Kanazawa. 2024. Shape of Motion: 4D Reconstruction from a Single Video. arXiv preprint arXiv:2407.13764 (2024).

[256] Wenguan Wang, Yi Yang, and Yunhe Pan. 2024. Visual Knowledge in the Big Model Era: Retrospect and Prospect. arXiv preprint arXiv:2404.04308 (2024).

[257] Yuehao Wang, Yonghao Long, Siu Hin Fan, and Qi Dou. 2022. Neural rendering for stereo 3d reconstruction of deformable tissues in robotic surgery. In Proc. Int. Conf. Med. Image Comput. Comput. Assist. Interv. 431–441.

[258] Yuxin Wang, Qianyi Wu, Guofeng Zhang, and Dan Xu. 2024. GScream: Learning 3D Geometry and Feature Consistent Gaussian Splatting for Object Removal. In Proc. Eur. Conf. Comput. Vis.

[259] Zhou Wang, Alan C Bovik, Hamid R Sheikh, and Eero P Simoncelli. 2004. Image quality assessment: from error visibility to structural similarity. IEEE Trans. Image Process. 13, 4 (2004), 600–612.

[260] Chung-Yi Weng, Brian Curless, Pratul P Srinivasan, Jonathan T Barron, and Ira Kemelmacher-Shlizerman. 2022. Humannerf: Free-viewpoint rendering of moving people from monocular video. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 16210–16220.

[261] Christopher Wewer, Kevin Raj, Eddy Ilg, Bernt Schiele, and Jan Eric Lenssen. 2024. latentSplat: Autoencoding Variational Gaussians for Fast Generalizable 3D Reconstruction. arXiv preprint arXiv:2403.16292 (2024).

[262] Chenyang Wu, Yifan Duan, Xinran Zhang, Yu Sheng, Jianmin Ji, and Yanyong Zhang. 2024. MM-Gaussian: 3D Gaussian-based Multi-modal Fusion for Localization and Reconstruction in Unbounded Scenes. In Proc. IEEE/RSJ Int. Conf. Intell. Robot. Syst.

[263] Guanjun Wu, Taoran Yi, Jiemin Fang, Lingxi Xie, Xiaopeng Zhang, Wei Wei, Wenyu Liu, Qi Tian, and Xinggang Wang. 2024. 4d gaussian splatting for real-time dynamic scene rendering. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[264] Jing Wu, Jia-Wang Bian, Xinghui Li, Guangrun Wang, Ian Reid, Philip Torr, and Victor Adrian Prisacariu. 2024. Gaussctrl: Multi-view consistent text-driven 3d gaussian splatting editing. In Proc. Eur. Conf. Comput. Vis. 55–71.

[265] Ke Wu, Kaizhao Zhang, Zhiwei Zhang, Shanshuai Yuan, Muer Tie, Julong Wei, Zijun Xu, Jieru Zhao, Zhongxue Gan, and Wenchao Ding. 2024. HGS-Mapping: Online Dense Mapping Using Hybrid Gaussian Representation in Urban Scenes. arXiv preprint arXiv:2403.20159 (2024).

<!-- page 33 of 41 -->

A Survey on 3D Gaussian Splatting

33

[266] Renlong Wu, Zhilu Zhang, Yu Yang, and Wangmeng Zuo. 2024. Dual-Camera Smooth Zoom on Mobile Phones. arXiv preprint arXiv:2404.04908 (2024).

[267] Tong Wu, Yu-Jie Yuan, Ling-Xiao Zhang, Jie Yang, Yan-Pei Cao, Ling-Qi Yan, and Lin Gao. 2024. Recent advances in 3d gaussian splatting. Comput. Vis. Media (2024), 1–30.

[268] Tong Wu, Jiarui Zhang, Xiao Fu, Yuxin Wang, Jiawei Ren, Liang Pan, Wayne Wu, Lei Yang, Jiaqi Wang, Chen Qian, et al. 2023. Omniobject3d: Large-vocabulary 3d object dataset for realistic perception, reconstruction and generation. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 803–814.

[269] Zijie Wu, Chaohui Yu, Yanqin Jiang, Chenjie Cao, Fan Wang, and Xiang Bai. 2024. SC4D: Sparse-Controlled Video-to-4D Generation and Motion Transfer. arXiv preprint arXiv:2404.03736 (2024).

[270] Jun Xiang, Xuan Gao, Yudong Guo, and Juyong Zhang. 2023. FlashAvatar: High-Fidelity Digital Avatar Rendering at 300FPS. arXiv preprint arXiv:2312.02214 (2023).

[271] Yuanbo Xiangli, Linning Xu, Xingang Pan, Nanxuan Zhao, Anyi Rao, Christian Theobalt, Bo Dai, and Dahua Lin. 2022. Bungeenerf: Progressive neural radiance field for extreme multi-scale scene rendering. In Proc. Eur. Conf. Comput. Vis. Springer, 106–122.

[272] Tianyi Xie, Zeshun Zong, Yuxin Qiu, Xuan Li, Yutao Feng, Yin Yang, and Chenfanfu Jiang. 2024. PhysGaussian: Physics-Integrated 3D Gaussians for Generative Dynamics. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[273] Yiheng Xie, Towaki Takikawa, Shunsuke Saito, Or Litany, Shiqin Yan, Numair Khan, Federico Tombari, James Tompkin, Vincent Sitzmann, and Srinath Sridhar. 2022. Neural fields in visual computing and beyond. In Comput. Graph. Forum. 641–676.

[274] Butian Xiong, Zhuo Li, and Zhen Li. 2024. GauU-Scene: A Scene Reconstruction Benchmark on Large Scale 3D Reconstruction Dataset Using Gaussian Splatting. arXiv preprint arXiv:2401.14032 (2024).

[275] Haolin Xiong, Sairisheek Muttukuru, Rishi Upadhyay, Pradyumna Chari, and Achuta Kadambi. 2023. SparseGS: Real-Time 360 {\deg} Sparse View Synthesis using Gaussian Splatting. arXiv preprint arXiv:2312.00206 (2023).

[276] Dejia Xu, Ye Yuan, Morteza Mardani, Sifei Liu, Jiaming Song, Zhangyang Wang, and Arash Vahdat. 2024. AGG: Amortized Generative 3D Gaussians for Single Image to 3D. arXiv preprint arXiv:2401.04099 (2024).

[277] Yuelang Xu, Benwang Chen, Zhe Li, Hongwen Zhang, Lizhen Wang, Zerong Zheng, and Yebin Liu. 2024. Gaussian head avatar: Ultra high-fidelity head avatar via dynamic gaussians. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[278] Yinghao Xu, Zifan Shi, Wang Yifan, Hansheng Chen, Ceyuan Yang, Sida Peng, Yujun Shen, and Gordon Wetzstein. 2024. Grm: Large gaussian reconstruction model for efficient 3d reconstruction and generation. In Proc. Eur. Conf. Comput. Vis. 1–20.

[279] Chi Yan, Delin Qu, Dong Wang, Dan Xu, Zhigang Wang, Bin Zhao, and Xuelong Li. 2024. GS-SLAM: Dense Visual SLAM with 3D Gaussian Splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[280] Yucheng Yan, Chen Liang, Wenguan Wang, and Yi Yang. 2026. Open-Set Semantic Gaussian Splatting SLAM with Expandable Representation. In Proc. Int. Conf. Learn. Represent.

[281] Yunzhi Yan, Haotong Lin, Chenxu Zhou, Weijie Wang, Haiyang Sun, Kun Zhan, Xianpeng Lang, Xiaowei Zhou, and Sida Peng. 2024. Street Gaussians for Modeling Dynamic Urban Scenes. In Proc. Eur. Conf. Comput. Vis.

[282] Zhiwen Yan, Chen Li, and Gim Hee Lee. 2023. Nerf-ds: Neural radiance fields for dynamic specular objects. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 8285–8295.

[283] Zhiwen Yan, Weng Fei Low, Yu Chen, and Gim Hee Lee. 2024. Multi-Scale 3D Gaussian Splatting for Anti-Aliased Rendering. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[284] Chen Yang, Sikuang Li, Jiemin Fang, Ruofan Liang, Lingxi Xie, Xiaopeng Zhang, Wei Shen, and Qi Tian. 2024. GaussianObject: Just Taking Four Images to Get A High-Quality 3D Object with Gaussian Splatting. arXiv preprint arXiv:2402.10259 (2024).

[285] Chen Yang, Kailing Wang, Yuehao Wang, Xiaokang Yang, and Wei Shen. 2023. Neural lerplane representations for fast 4d reconstruction of deformable tissues. In Proc. Int. Conf. Med. Image Comput. Comput. Assist. Interv. 46–56.

[286] Guoqing Yang, Fuyou Xue, Qi Zhang, Ke Xie, Chi-Wing Fu, and Hui Huang. 2023. UrbanBIS: a large-scale benchmark for fine-grained urban building instance segmentation. In Proc. ACM Spec. Interest Group Comput. Graph. Interact. Tech. 1–11.

[287] Xiaofeng Yang, Yiwen Chen, Cheng Chen, Chi Zhang, Yi Xu, Xulei Yang, Fayao Liu, and Guosheng Lin. 2023. Learn to Optimize Denoising Scores for 3D Generation: A Unified and Improved Diffusion Prior on NeRF and 3D Gaussian Splatting. arXiv preprint arXiv:2312.04820 (2023).

[288] Xingrui Yang, Hai Li, Hongjia Zhai, Yuhang Ming, Yuqian Liu, and Guofeng Zhang. 2022. Vox-Fusion: Dense tracking and mapping with voxel-based neural implicit representation. In IEEE International Symposium on Mixed and Augmented Reality. 499–507.

[289] Xingyi Yang and Xinchao Wang. 2024. Hash3D: Training-free Acceleration for 3D Generation. arXiv preprint arXiv:2404.06091 (2024).

[290] Ziyi Yang, Xinyu Gao, Yangtian Sun, Yihua Huang, Xiaoyang Lyu, Wen Zhou, Shaohui Jiao, Xiaojuan Qi, and Xiaogang Jin. 2024. Spec-Gaussian: Anisotropic View-Dependent Appearance for 3D Gaussian Splatting. arXiv preprint arXiv:2402.15870 (2024).

[291] Ziyi Yang, Xinyu Gao, Wen Zhou, Shaohui Jiao, Yuqing Zhang, and Xiaogang Jin. 2024. Deformable 3d gaussians for high-fidelity monocular dynamic scene reconstruction. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[292] Zeyu Yang, Hongye Yang, Zijie Pan, Xiatian Zhu, and Li Zhang. 2024. Real-time photorealistic dynamic scene representation and rendering with 4d gaussian splatting. In Proc. Int. Conf. Learn. Represent.

[293] Keyang Ye, Tianjia Shao, and Kun Zhou. 2023. Animatable 3D Gaussians for High-fidelity Synthesis of Human Motions. arXiv preprint arXiv:2311.13404 (2023).

Manuscript submitted to ACM

<!-- page 34 of 41 -->

34

Guikun Chen and Wenguan Wang

[294] Keyang Ye, Tianjia Shao, and Kun Zhou. 2025. When gaussian meets surfel: Ultra-fast high-fidelity radiance field rendering. ACM Trans. Graph. 44, 4 (2025), 1–15.

[295] Mingqiao Ye, Martin Danelljan, Fisher Yu, and Lei Ke. 2024. Gaussian Grouping: Segment and Edit Anything in 3D Scenes. In Proc. Eur. Conf. Comput. Vis.

[296] Taoran Yi, Jiemin Fang, Junjie Wang, Guanjun Wu, Lingxi Xie, Xiaopeng Zhang, Wenyu Liu, Qi Tian, and Xinggang Wang. 2024. GaussianDreamer: Fast Generation from Text to 3D Gaussians by Bridging 2D and 3D Diffusion Models. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[297] Wang Yifan, Felice Serena, Shihao Wu, Cengiz Öztireli, and Olga Sorkine-Hornung. 2019. Differentiable surface splatting for point-based geometry processing. ACM Trans. Graph. 38, 6 (2019), 1–14.

[298] Yuyang Yin, Dejia Xu, Zhangyang Wang, Yao Zhao, and Yunchao Wei. 2023. 4DGen: Grounded 4D Content Generation with Spatial-temporal Consistency. arXiv preprint arXiv:2312.17225 (2023).

[299] Alex Yu, Vickie Ye, Matthew Tancik, and Angjoo Kanazawa. 2021. pixelnerf: Neural radiance fields from one or few images. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 4578–4587.

[300] Heng Yu, Joel Julin, Zoltán Á Milacski, Koichiro Niinuma, and László A Jeni. 2024. CoGS: Controllable Gaussian Splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[301] Mulin Yu, Tao Lu, Linning Xu, Lihan Jiang, Yuanbo Xiangli, and Bo Dai. 2024. GSDF: 3DGS Meets SDF for Improved Rendering and Reconstruction. arXiv preprint arXiv:2403.16964 (2024).

[302] Tao Yu, Zerong Zheng, Kaiwen Guo, Pengpeng Liu, Qionghai Dai, and Yebin Liu. 2021. Function4d: Real-time human volumetric capture from very sparse consumer rgbd sensors. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 5746–5756.

[303] Zehao Yu, Anpei Chen, Binbin Huang, Torsten Sattler, and Andreas Geiger. 2024. Mip-Splatting: Alias-free 3D Gaussian Splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 19447–19456.

[304] Zehao Yu, Torsten Sattler, and Andreas Geiger. 2024. Gaussian opacity fields: Efficient and compact surface reconstruction in unbounded scenes. arXiv preprint arXiv:2404.10772 (2024).

[305] Ye Yuan, Xueting Li, Yangyi Huang, Shalini De Mello, Koki Nagano, Jan Kautz, and Umar Iqbal. 2024. GAvatar: Animatable 3D Gaussian Avatars with Implicit Mesh Learning. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[306] Vladimir Yugay, Yue Li, Theo Gevers, and Martin R Oswald. 2023. Gaussian-SLAM: Photo-realistic Dense SLAM with Gaussian Splatting. arXiv preprint arXiv:2312.10070 (2023).

[307] Ruyi Zha, Xuelian Cheng, Hongdong Li, Mehrtash Harandi, and Zongyuan Ge. 2023. Endosurf: Neural surface reconstruction of deformable tissues with stereo endoscope videos. In Proc. Int. Conf. Med. Image Comput. Comput. Assist. Interv. 13–23.

[308] Zhichao Zhai, Guikun Chen, Wenguan Wang, Dong Zheng, and Jun Xiao. 2025. TAGA: Self-supervised Learning for Template-free Animatable Gaussian Articulated Model. In CVPR. 21159–21169.

[309] Bowen Zhang, Yiji Cheng, Jiaolong Yang, Chunyu Wang, Feng Zhao, Yansong Tang, Dong Chen, and Baining Guo. 2024. GaussianCube: Structuring Gaussian Splatting using Optimal Transport for 3D Generative Modeling. arXiv preprint arXiv:2403.19655 (2024).

[310] Baowen Zhang, Chuan Fang, Rakesh Shrestha, Yixun Liang, Xiaoxiao Long, and Ping Tan. 2024. RaDe-GS: Rasterizing Depth in Gaussian Splatting. arXiv preprint arXiv:2406.01467 (2024).

[311] Dingxi Zhang, Zhuoxun Chen, Yu-Jie Yuan, Fang-Lue Zhang, Zhenliang He, Shiguang Shan, and Lin Gao. 2024. StylizedGS: Controllable Stylization for 3D Gaussian Splatting. arXiv preprint arXiv:2404.05220 (2024).

[312] Jiawei Zhang, Jiahe Li, Xiaohan Yu, Lei Huang, Lin Gu, Jin Zheng, and Xiao Bai. 2024. CoR-GS: Sparse-View 3D Gaussian Splatting via Co-Regularization. In Proc. Eur. Conf. Comput. Vis.

[313] Junwu Zhang, Zhenyu Tang, Yatian Pang, Xinhua Cheng, Peng Jin, Yida Wei, Wangbo Yu, Munan Ning, and Li Yuan. 2023. Repaint123: Fast and High-quality One Image to 3D Generation with Progressive Controllable 2D Repainting. arXiv preprint arXiv:2312.13271 (2023).

[314] Jiahui Zhang, Fangneng Zhan, Muyu Xu, Shijian Lu, and Eric Xing. 2024. FreGS: 3D Gaussian Splatting with Progressive Frequency Regularization. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[315] Kai Zhang, Sai Bi, Hao Tan, Yuanbo Xiangli, Nanxuan Zhao, Kalyan Sunkavalli, and Zexiang Xu. 2024. Gs-lrm: Large reconstruction model for 3d gaussian splatting. In Proc. Eur. Conf. Comput. Vis. 1–19.

[316] Qihang Zhang, Yinghao Xu, Chaoyang Wang, Hsin-Ying Lee, Gordon Wetzstein, Bolei Zhou, and Ceyuan Yang. 2024. 3DitScene: Editing Any Scene via Language-guided Disentangled Gaussian Splatting. arXiv preprint arXiv:2405.18424 (2024).

[317] Richard Zhang, Phillip Isola, Alexei A Efros, Eli Shechtman, and Oliver Wang. 2018. The unreasonable effectiveness of deep features as a perceptual metric. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 586–595.

[318] Shuai Zhang, Huangxuan Zhao, Zhenghong Zhou, Guanjun Wu, Chuansheng Zheng, Xinggang Wang, and Wenyu Liu. 2024. TOGS: Gaussian Splatting with Temporal Opacity Offset for Real-Time 4D DSA Rendering. arXiv preprint arXiv:2403.19586 (2024).

[319] Tianyuan Zhang, Sai Bi, Yicong Hong, Kai Zhang, Fujun Luan, Songlin Yang, Kalyan Sunkavalli, William T Freeman, and Hao Tan. 2026. Test-Time Training Done Right. In Proc. Int. Conf. Learn. Represent.

[320] Tianyi Zhang, Kaining Huang, Weiming Zhi, and Matthew Johnson-Roberson. 2024. DarkGS: Learning Neural Illumination and 3D Gaussians Relighting for Robotic Exploration in the Dark. In Proc. IEEE/RSJ Int. Conf. Intell. Robot. Syst.

[321] Tianyuan Zhang, Hong-Xing Yu, Rundi Wu, Brandon Y Feng, Changxi Zheng, Noah Snavely, Jiajun Wu, and William T Freeman. 2024. Physdreamer: Physics-based interaction with 3d objects via video generation. In Proc. Eur. Conf. Comput. Vis. 388–406.

Manuscript submitted to ACM

<!-- page 35 of 41 -->

A Survey on 3D Gaussian Splatting

35

[322] Xinjie Zhang, Xingtong Ge, Tongda Xu, Dailan He, Yan Wang, Hongwei Qin, Guo Lu, Jing Geng, and Jun Zhang. 2024. GaussianImage: 1000 FPS Image Representation and Compression by 2D Gaussian Splatting. In Proc. Eur. Conf. Comput. Vis.

[323] Hexu Zhao, Haoyang Weng, Daohan Lu, Ang Li, Jinyang Li, Aurojit Panda, and Saining Xie. 2024. On Scaling Up 3D Gaussian Splatting Training. arXiv preprint arXiv:2406.18533 (2024).

[324] Haoyu Zhao, Xingyue Zhao, Lingting Zhu, Weixi Zheng, and Yongchao Xu. 2024. HFGS: 4D Gaussian Splatting with Emphasis on Spatial and Temporal High-Frequency Components for Endoscopic Scene Reconstruction. arXiv preprint arXiv:2405.17872 (2024).

[325] Lingzhe Zhao, Peng Wang, and Peidong Liu. 2024. BAD-Gaussians: Bundle Adjusted Deblur Gaussian Splatting. arXiv preprint arXiv:2403.11831 (2024).

[326] Zhongyuan Zhao, Zhenyu Bao, Qing Li, Guoping Qiu, and Kanglin Liu. 2024. PSAvatar: A Point-based Morphable Shape Model for Real-Time Head Avatar Creation with 3D Gaussian Splatting. arXiv preprint arXiv:2401.12900 (2024).

[327] Shunyuan Zheng, Boyao Zhou, Ruizhi Shao, Boning Liu, Shengping Zhang, Liqiang Nie, and Yebin Liu. 2024. GPS-Gaussian: Generalizable Pixel-wise 3D Gaussian Splatting for Real-time Human Novel View Synthesis. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[328] Yuhang Zheng, Xiangyu Chen, Yupeng Zheng, Songen Gu, Runyi Yang, Bu Jin, Pengfei Li, Chengliang Zhong, Zengmao Wang, Lina Liu, et al. 2024. GaussianGrasper: 3D Language Gaussian Splatting for Open-vocabulary Robotic Grasping. arXiv preprint arXiv:2403.09637 (2024).

[329] Zerong Zheng, Tao Yu, Yixuan Wei, Qionghai Dai, and Yebin Liu. 2019. Deephuman: 3d human reconstruction from a single image. In Proc. IEEE Int. Conf. Comput. Vis. 7739–7749.

[330] Licheng Zhong, Hong-Xing Yu, Jiajun Wu, and Yunzhu Li. 2024. Reconstruction and Simulation of Elastic Objects with Spring-Mass 3D Gaussians. In Proc. Eur. Conf. Comput. Vis.

[331] Hongyu Zhou, Jiahao Shao, Lu Xu, Dongfeng Bai, Weichao Qiu, Bingbing Liu, Yue Wang, Andreas Geiger, and Yiyi Liao. 2024. HUGS: Holistic Urban 3D Scene Understanding via Gaussian Splatting. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 21336–21345.

[332] Shijie Zhou, Haoran Chang, Sicheng Jiang, Zhiwen Fan, Zehao Zhu, Dejia Xu, Pradyumna Chari, Suya You, Zhangyang Wang, and Achuta Kadambi. 2024. Feature 3DGS: Supercharging 3D Gaussian Splatting to Enable Distilled Feature Fields. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[333] Shijie Zhou, Zhiwen Fan, Dejia Xu, Haoran Chang, Pradyumna Chari, Tejas Bharadwaj, Suya You, Zhangyang Wang, and Achuta Kadambi. 2024. DreamScene360: Unconstrained Text-to-3D Scene Generation with Panoramic Gaussian Splatting. In Proc. Eur. Conf. Comput. Vis.

[334] Tinghui Zhou, Richard Tucker, John Flynn, Graham Fyffe, and Noah Snavely. 2018. Stereo magnification: learning view synthesis using multiplane images. ACM Trans. Graph. 37, 4 (2018), 1–12.

[335] Xiaoyu Zhou, Zhiwei Lin, Xiaojun Shan, Yongtao Wang, Deqing Sun, and Ming-Hsuan Yang. 2024. DrivingGaussian: Composite Gaussian Splatting for Surrounding Dynamic Autonomous Driving Scenes. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[336] Zhenglin Zhou, Fan Ma, Hehe Fan, and Yi Yang. 2024. HeadStudio: Text to Animatable Head Avatars with 3D Gaussian Splatting. In Proc. Eur. Conf. Comput. Vis.

[337] Jialin Zhu, Jiangbei Yue, Feixiang He, and He Wang. 2025. 3d student splatting and scooping. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 21045–21054.

[338] Lingting Zhu, Zhao Wang, Zhenchao Jin, Guying Lin, and Lequan Yu. 2024. Deformable Endoscopic Tissues Reconstruction with Gaussian Splatting. arXiv preprint arXiv:2401.11535 (2024).

[339] Siting Zhu, Renjie Qin, Guangming Wang, Jiuming Liu, and Hesheng Wang. 2024. Semgauss-slam: Dense semantic gaussian splatting slam. arXiv preprint arXiv:2403.07494 (2024).

[340] Zehao Zhu, Zhiwen Fan, Yifan Jiang, and Zhangyang Wang. 2024. FSGS: Real-Time Few-shot View Synthesis using Gaussian Splatting. In Proc. Eur. Conf. Comput. Vis.

[341] Zihan Zhu, Songyou Peng, Viktor Larsson, Weiwei Xu, Hujun Bao, Zhaopeng Cui, Martin R Oswald, and Marc Pollefeys. 2022. Nice-slam: Neural implicit scalable encoding for slam. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit. 12786–12796.

[342] Jingyu Zhuang, Di Kang, Yan-Pei Cao, Guanbin Li, Liang Lin, and Ying Shan. 2024. TIP-Editor: An Accurate 3D Editor Following Both Text-Prompts And Image-Prompts. arXiv preprint arXiv:2401.14828 (2024).

[343] Wenjie Zhuo, Fan Ma, Hehe Fan, and Yi Yang. 2024. VividDreamer: Invariant Score Distillation For Hyper-Realistic Text-to-3D Generation. In Proc. Eur. Conf. Comput. Vis.

[344] Chen Ziwen, Hao Tan, Peng Wang, Zexiang Xu, and Li Fuxin. 2025. Long-LRM++: Preserving Fine Details in Feed-Forward Wide-Coverage Reconstruction. arXiv preprint arXiv:2512.10267 (2025).

[345] Chen Ziwen, Hao Tan, Kai Zhang, Sai Bi, Fujun Luan, Yicong Hong, Li Fuxin, and Zexiang Xu. 2025. Long-lrm: Long-sequence large reconstruction model for wide-coverage gaussian splats. In Proc. IEEE Int. Conf. Comput. Vis. 4349–4359.

[346] Zi-Xin Zou, Zhipeng Yu, Yuan-Chen Guo, Yangguang Li, Ding Liang, Yan-Pei Cao, and Song-Hai Zhang. 2024. Triplane Meets Gaussian Splatting: Fast and Generalizable Single-View 3D Reconstruction with Transformers. In Proc. IEEE Conf. Comput. Vis. Pattern Recognit.

[347] Xingxing Zuo, Pouya Samangouei, Yunwen Zhou, Yan Di, and Mingyang Li. 2024. FMGS: Foundation Model Embedded 3D Gaussian Splatting for Holistic 3D Scene Understanding. arXiv preprint arXiv:2401.01970 (2024).

[348] Matthias Zwicker, Hanspeter Pfister, Jeroen Van Baar, and Markus Gross. 2001. EWA volume splatting. In Proceedings Visualization, 2001. VIS’01. 29–538.

[349] Matthias Zwicker, Hanspeter Pfister, Jeroen Van Baar, and Markus Gross. 2001. Surface splatting. In Proceedings of the 28th annual conference on Computer graphics and interactive techniques. 371–378.

Manuscript submitted to ACM

<!-- page 36 of 41 -->

36

Guikun Chen and Wenguan Wang

[350] Matthias Zwicker, Hanspeter Pfister, Jeroen Van Baar, and Markus Gross. 2002. EWA splatting. IEEE Trans. Vis. Comput. Graph. 8, 3 (2002), 223–238.

Manuscript submitted to ACM

<!-- page 37 of 41 -->

A Survey on 3D Gaussian Splatting

37

## SUPPLEMENTARY MATERIAL

Due to the page limit of the main manuscript, we provide additional figures and tables in this supplementary material. Specifically, we include i) a visualization of the 3D GS growth process; **ii**) a visual comparison between NeRFs and 3D GS; **iii**) a demonstration of tile-based parallel rendering; **iv**) a consolidated summary table of the commonly used datasets; and v) detailed quantitative performance-comparison tables. These figures and tables are referenced from the main text and are intended to improve completeness without interrupting the main narrative.

![Chart block](images/chen2024_3dgs-survey_p37_b5.png)

Fig. S1. The number of published papers and GitHub stars on 3D GS. Statistics sourced from [# Papers](https://github.com/Awesome3DGS/3D-Gaussian-Splatting-Papers) and [# GitHub Stars.](https://star-history.com/#graphdeco-inria/gaussian-splatting&Date)

![Image block](images/chen2024_3dgs-survey_p37_b7.png)

![Image block](images/chen2024_3dgs-survey_p37_b8.png)

Fig. S2. NeRFs vs. 3D GS. (a) NeRF samples along the ray and then queries the MLP to obtain colors and densities, which can be seen as a backward mapping (ray tracing). (b) 3D GS projects all 3D Gaussians into the image space (i.e., splatting) and then performs parallel rendering, which can be viewed as a forward mapping (rasterization).

Manuscript submitted to ACM

<!-- page 38 of 41 -->

38

Guikun Chen and Wenguan Wang

![Image block](images/chen2024_3dgs-survey_p38_b3.png)

Fig. S3. An illustration of the tile based parallel (at the pixel-level) rendering. All the pixels within a tile (Tile1 here) access the same ordered Gaussian list stored in a shared memory for rendering. As the system processes each Gaussian sequentially, every pixel in the tile evaluates the Gaussian’s contribution according to the distance (i.e., the exp term in Eq. 6). Therefore, the rendering for a tile can be completed by iterating through the list of Gaussians just once. The computation for the red Gaussian follows a similar way and is omitted here for simplicity.

Table S1. Summary of major 3DGS research directions reviewed in Section 4. For each direction, representative works are listed in chronological order, providing a rough timeline of progress.

| Direction | Key ideas | Representative works | Advantages | Limitations / challenges |
| --- | --- | --- | --- | --- |
|  |  |  |  |  |
| §4.1 3DGS for | Handle few-view / sparse | [26, 32, 133, 225, | Supports limited viewpoints; en- | Trade-offbetween geometry quality and |
| Sparse Input | inputs via regularization or learned priors | 239, 241, 261, 275,278, 312, 340] | ables single-image or few-shot NVS; leverages strong 3D priors | speed; sensitive to prior/regularization choice; dynamic scenes remain difficult |
| §4.2 Memory- | Reduce Gaussian count and/or | [31, 48, 49, 124, 178, | Lower memory footprint; scalable | Quality drop at high compression; |
| efficient 3DGS | compress Gaussian attributes for compact storage | 182, 183, 188, 322] | to large scenes and datasets; facili-tates deployment and streaming | training-time memory is still high; de-signing reusable codebooks is open |
| §4.3 Photoreal- | Improve aliasing, reflection, | [15, 38, 102, 123, | Sharper details; more realistic mate- | Pipelines become more complex; many |
| istic 3D GS | blur, and shading to boost vi-sual fidelity | 139, 145, 205, 220,231, 283, 290, 303,325] | rials and lighting; increased robust-ness on real captures | methods target specific artifacts; may increase training and rendering cost |
| §4.4 Improved | Better optimization and regu- | [59, 88, 106, 132, | Faster convergence; fewer floater- | Still per-scene optimization; hyperpa- |
| Optimization | larization pipelines for more | 139, 160, 301, 314] | s/artifacts; more robust reconstruc- | rameter and schedule tuning; limited |
| Algorithms | stable training |  | tion in challenging scenes | work on meta-learning or few-shot GS |
| §4.5 3D Gauss- | Attach semantic or spatiotem- | [24, 202, 226, 292, | Enables open-vocabulary querying, | Higher memory and computation; de- |
| ians with More | poral features to Gaussians for | 295, 332, 347] | semantic editing, spatiotemporal | pends on large-scale supervision; Evalu- |
| Properties | richer scene understanding |  | modeling, etc. | ation protocols are still emerging |
| §4.6 Hybrid Re- | Combine Gaussians with struc- | [218, 263, 277, 291] | Adds structure and controllabil- | More complex architectures; less |
| presentations | turedmodules(MLPs,deforma-tion fields) for specific tasks |  | ity; effective for avatars, dynamic scenes, stylization, etc. | generic; partially loses the simplicity of pure GS |
| §4.7 New | Devise ray tracing / physically- | [36, 166, 176] | Better handling of visibility, sec- | Higher computational cost; integration |
| Rendering | based and improved rasteriza- |  | ondary rays, and complex cameras; | with real-time pipelines is still in early |
| Algorithms | tion for Gaussians |  | improved physical correctness | stages; APIs and tooling are immature |

Table S2. Comparison of regularization-based and generalizability-based 3DGS methods for sparse input.

| Dimension | Regularization-based | Generalizability-based |
| --- | --- | --- |
| Inference speed | Slow; per-scene optimization | Fast; feed-forward |
| Reconstruction quality | High detail; strong geometry | Lower accuracy; priors may hallucinate |
| Views required at test time | Typically multi-view | Few views; even single image |
| Robustness to unseen regions | Limited; overfits observed views | Depends on prior; plausible but inexact |
| Typical use cases | High-fidelity reconstruction | Real-time / interactive NVS |
| Representative works | [32, 133, 312, 340] | [26, 240, 241, 278] |

Manuscript submitted to ACM

<!-- page 39 of 41 -->

A Survey on 3D Gaussian Splatting

39

Table S3. Collection of representative datasets for 3D GS. Here PC represents point clouds.

| Name | Type | # Sample | Area and Task |
| --- | --- | --- | --- |
| Tanks&amp;Temples [114] [TOG17] | RGB | 14 |  |
| RealEstate10K [334] [TOG18] | RGB | 1,000 |  |
| DeepBlending [77] [TOG18] | RGB | 19 |  |
| LLFF [173] [TOG19] | RGB | 8 | Novel View Synthesis |
| NeRF [174] [ECCV20] | RGB | 8 |  |
| ACID [150] [ICCV21] | RGB | 700+ |  |
| Mip-NeRF 360 [13] [CVPR22] | RGB | 9 |  |
| TUM RGB-D [233] [IROS12] | RGB-D | 39 |  |
| KITTI [65] [CVPR12] | RGB-D&amp;PC | 11 |  |
| ScanNet [39] [CVPR17] | RGB-D | 1,513 |  |
| Replica [232] [arXiv19] | RGB-D | 18 |  |
| Waymo [237] [CVPR20] | RGB-D&amp;PC | 1,150 | Robotics |
| nuScenes [19] [CVPR20] | RGB-D&amp;PC | 1,000 |  |
| RLBench [93] [RA-L20] | RGB | 100 |  |
| Robomimic [167] [CoRL22] | RGB | 800 |  |
| D-NeRF [199] [CVPR21] | RGB | 8 |  |
| HyperNeRF [191] [TOG21] | RGB | 6 | Dynamic Scene Reconstruction |
| NeRF-DS [282] [CVPR23] | RGB | 8 |  |
| CoNeRF [108] [CVPR22] | RGB | 7 |  |
| SPIn-NeRF [175] [CVPR23] | RGB | 10 |  |
| Tensor4D [222] [CVPR23] | RGB | 4 | Generation and Editing |
| OmniObject3D [268] [CVPR23] | 3D Object | 6,000 |  |
| Objaverse [43] [CVPR23] | 3D Object | 800K+ |  |
| People-Snapshot [8] [CVPR18] | RGB | 24 |  |
| VOCASET [37] [CVPR19] | RGB | 12 |  |
| THUman [329] [ICCV19] | RGB | 200 |  |
| THUman2.0 [302] [CVPR21] | RGB-D | 500 | Avatar |
| ZJU-Mocap [195] [CVPR21] | RGB | 9 |  |
| H3DS [206] [ICCV21] | RGB | 23 |  |
| THUman3.0 [234] [TPAMI22] | 3D Scan | 20 |  |
| SCARED [7] [MICCAI19] | RGB-D | 9 |  |
| EndoNeRF [257] [MICCAI22] | RGB | 2 | Medical Systems |
| X3D [21] [CVPR24] | X-ray | 15 |  |
| CityNeRF [271] [ECCV22] | RGB | 12 |  |
| Waymo Block-NeRF [242] [CVPR22] | RGB&amp;PC | 1 | Large-scale Reconstrction |
| UrbanBIS [286] [SIGGR23] | RGB&amp;PC | 6 |  |
| GauU-Scene [274] [arXiv24] | RGB&amp;PC | 1 |  |

Manuscript submitted to ACM

<!-- page 40 of 41 -->

40

Guikun Chen and Wenguan Wang

Table S4. Comparison of localization methods on Replica [232] (static scenes), in terms of absolute trajectory error (ATE, cm). (The three best scores are marked in red, blue, and green, respectively. These notes also apply to the other tables.)

| Method | GS Room0 | Room1 | Room2 | Office0 | Office1 | Office2 | Office3 | Office4 | Avarage |
| --- | --- | --- | --- | --- | --- | --- | --- | --- | --- |
| iMAP [235] [ICCV21] | 3.12 | 2.54 | 2.31 | 1.69 | 1.03 | 3.99 | 4.05 | 1.93 | 2.58 |
| Vox-Fusion [288] [ISMAR22] | 1.37 | 4.70 | 1.47 | 8.48 | 2.04 | 2.58 | 1.11 | 2.94 | 3.09 |
| NICE-SLAM [341] [CVPR22] | 0.97 | 1.31 | 1.07 | 0.88 | 1.00 | 1.06 | 1.10 | 1.13 | 1.06 |
| ESLAM [104] [CVPR23] | 0.71 | 0.70 | 0.52 | 0.57 | 0.55 | 0.58 | 0.72 | 0.63 | 0.63 |
| Point-SLAM [215] [ICCV23] | 0.61 | 0.41 | 0.37 | 0.38 | 0.48 | 0.54 | 0.69 | 0.72 | 0.52 |
| Co-SLAM [251] [CVPR23] | 0.70 | 0.95 | 1.35 | 0.59 | 0.55 | 2.03 | 1.56 | 0.72 | 1.00 |
| Gaussian-SLAM [306] [arXiv] | ✓ 3.35 | 8.74 | 3.13 | 1.11 | 0.81 | 0.78 | 1.08 | 7.21 | 3.27 |
| GSSLAM [168] [CVPR24] | ✓ 0.47 | 0.43 | 0.31 | 0.70 | 0.57 | 0.31 | 0.31 | 3.20 | 0.79 |
| GS-SLAM [279] [CVPR24] | ✓ 0.48 | 0.53 | 0.33 | 0.52 | 0.41 | 0.59 | 0.46 | 0.70 | 0.50 |
| SplaTAM [110] [CVPR24] | ✓ 0.31 | 0.40 | 0.29 | 0.47 | 0.27 | 0.29 | 0.32 | 0.55 | 0.36 |

Table S5. Comparison of mapping methods on Replica [232] (static scenes), in terms of PSNR, SSIM, and LPIPS. FPS is measured using NVIDIA 4090 [168].

| Method | GS | Metric | Room0 | Room1 | Room2 | Office0 | Office1 | Office2 | Office3 | Office4 | Avarage | FPS |
| --- | --- | --- | --- | --- | --- | --- | --- | --- | --- | --- | --- | --- |
|  |  | PSNR↑ | 22.12 | 22.47 | 24.52 | 29.07 | 30.34 | 19.66 | 22.23 | 24.94 | 24.42 |  |
| NICE-SLAM [341] [CVPR22] |  | SSIM↑ LPIPS↓ | 0.690.33 | 0.760.27 | 0.810.21 | 0.870.23 | 0.890.18 | 0.800.23 | 0.800.21 | 0.860.20 | 0.810.23 | 0.54 |
|  |  | PSNR↑ | 22.39 | 22.36 | 23.92 | 27.79 | 29.83 | 20.33 | 23.47 | 25.21 | 24.41 |  |
| Vox-Fusion [288] [ISMAR22] |  | SSIM↑ LPIPS↓ | 0.680.30 | 0.750.27 | 0.800.23 | 0.860.24 | 0.880.18 | 0.790.24 | 0.800.21 | 0.850.20 | 0.800.24 | 2.17 |
|  |  | PSNR↑ | 32.40 | 34.08 | 35.50 | 38.26 | 39.16 | 33.99 | 33.48 | 33.49 | 35.17 |  |
| Point-SLAM [215] [ICCV23] |  | SSIM↑ LPIPS↓ | 0.970.11 | 0.980.12 | 0.980.11 | 0.980.10 | 0.990.12 | 0.960.16 | 0.960.13 | 0.980.14 | 0.970.12 | 1.33 |
|  |  | PSNR↑ | 32.86 | 33.89 | 35.25 | 38.26 | 39.17 | 31.97 | 29.70 | 31.81 | 34.11 |  |
| SplaTAM [110] [CVPR24] | ✓ | SSIM↑ LPIPS↓ | 0.980.07 | 0.970.10 | 0.980.08 | 0.980.09 | 0.980.09 | 0.970.10 | 0.950.12 | 0.950.15 | 0.970.10 | - |
|  |  | PSNR↑ | 31.56 | 32.86 | 32.59 | 38.70 | 41.17 | 32.36 | 32.03 | 32.92 | 34.27 |  |
| GS-SLAM [279] [CVPR24] | ✓ | SSIM↑ LPIPS↓ | 0.970.09 | 0.970.07 | 0.970.09 | 0.990.05 | 0.990.03 | 0.980.09 | 0.970.11 | 0.970.11 | 0.970.08 | - |
|  |  | PSNR↑ | 34.83 | 36.43 | 37.49 | 39.95 | 42.09 | 36.24 | 36.70 | 36.07 | 37.50 |  |
| GSSLAM [168] [CVPR24] | ✓ | SSIM↑ LPIPS↓ | 0.950.07 | 0.960.08 | 0.960.07 | 0.970.07 | 0.980.06 | 0.960.08 | 0.960.07 | 0.960.10 | 0.960.07 | 769 |
|  |  | PSNR↑ | 34.31 | 37.28 | 38.18 | 43.97 | 43.56 | 37.39 | 36.48 | 40.19 | 38.90 |  |
| Gaussian-SLAM [306] [arXiv] | ✓ | SSIM↑ LPIPS↓ | 0.990.08 | 0.990.07 | 0.990.07 | 1.000.04 | 0.990.07 | 0.990.08 | 0.990.08 | 1.000.07 | 0.990.07 | - |

Table S6. Comparison of reconstruction methods on D-NeRF [199] (dynamic scenes), in terms of PSNR, SSIM, and LPIPS. ∗ denotes results reported in [263].

| Method | GS | PSNR↑ | SSIM↑ | LPIPS↓ |
| --- | --- | --- | --- | --- |
| D-NeRF [199] [CVPR21] |  | 30.50 | 0.95 | 0.07 |
| TiNeuVox-B [51] [SGA22] |  | 32.67 | 0.97 | 0.04 |
| KPlanes [57] [CVPR23] |  | 31.61 | 0.97 | - |
| HexPlane-Slim [23] [CVPR23] |  | 32.68 | 0.97 | 0.02 |
| FFDNeRF [72] [ICCV23] |  | 32.68 | 0.97 | 0.02 |
| MSTH [250] [NeurIPS23] |  | 31.34 | 0.98 | 0.02 |
| 3D GS<sup>∗</sup> [111] [TOG23] | ✓ | 23.19 | 0.93 | 0.08 |
| 4DGS [292] [ICLR24] | ✓ | 34.09 | 0.98 | - |
| 4D-GS [263] [CVPR24] | ✓ | 34.05 | 0.98 | 0.02 |
| GaGS [161] [CVPR24] | ✓ | 37.36 | 0.99 | 0.01 |
| CoGS [300] [CVPR24] | ✓ | 37.90 | 0.98 | 0.02 |
| D-3DGS [291] [CVPR24] | ✓ | 39.51 | 0.99 | 0.01 |

Table S7. Comparison of reconstruction methods on ZJU-MoCap [195] (avatar), in terms of PSNR, SSIM, and LPIPS\* (LPIPS × 1000). The results for non-GS methods are taken from [126].

| Method | GS PSNR↑ | SSIM↑ | LPIPS*↓ |
| --- | --- | --- | --- |
| NeuralBody [195] [CVPR21] | 29.03 | 0.96 | 42.47 |
| AnimNeRF [194] [ICCV21] | 29.77 | 0.96 | 46.89 |
| PixelNeRF [299] [ICCV21] | 24.71 | 0.89 | 121.86 |
| NHP [118] [NeurIPS21] | 28.25 | 0.95 | 64.77 |
| HumanNeRF [260] [CVPR22] | 30.66 | 0.97 | 33.38 |
| Instant-NVR [66] [CVPR23] | 31.01 | 0.97 | 38.45 |
| GauHuman [82] [CVPR24] | ✓ 31.34 | 0.97 | 30.51 |
| 3DGS-Avatar [201] [CVPR24] | ✓ 30.61 | 0.97 | 29.58 |
| GART [126] [CVPR24] | ✓ 32.22 | 0.98 | 29.21 |

Manuscript submitted to ACM

<!-- page 41 of 41 -->

A Survey on 3D Gaussian Splatting

41

Table S8. Comparison of reconstruction methods on EndoNeRF [257] (surgical scenes), in terms of PSNR, SSIM, and LPIPS. The results for non-GS methods are taken from [157]. FPS is measured using NVIDIA 4090 [157].

| Method | GS PSNR↑ | SSIM↑ | LPIPS↓ | FPS↑ | Mem.↓ |
| --- | --- | --- | --- | --- | --- |
| EndoNeRF [257][MICCAI22] | 36.06 | 0.93 | 0.09 | 0.04 | 19GB |
| EndoSurf[307][MICCAI23] | 36.53 | 0.95 | 0.07 | 0.04 | 17GB |
| LerPlane-9k [285][MICCAI23] | 35.00 | 0.93 | 0.08 | 0.91 | 20GB |
| LerPlane-32k [285][MICCAI23] | 37.38 | 0.95 | 0.05 | 0.87 | 20GB |
| Endo-4DGS [90][MICCAI24] | ✓ 37.00 | 0.96 | 0.05 | - | 4GB |
| EndoGaussian [157][arXiv] | ✓ 37.85 | 0.96 | 0.05 | 195.09 | 2GB |
| HFGS [324][BMVC24] | ✓ 38.14 | 0.97 | 0.03 | - | - |

Manuscript submitted to ACM