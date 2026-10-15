<!-- page 1 of 13 -->

arXiv:2403.17888v3 [cs.CV] 22 Feb 2025

# 2D Gaussian Splatting for Geometrically Accurate Radiance Fields

BINBIN HUANG, ShanghaiTech University, China

ZEHAO YU, University of Tübingen Tübingen AI Center, Germany

ANPEI CHEN, University of Tübingen Tübingen AI Center, Germany

ANDREAS GEIGER, University of Tübingen Tübingen AI Center, Germany

SHENGHUA GAO, ShanghaiTech University, China

## [https://surfsplatting.github.io](https://surfsplatting.github.io)

![Image block](images/huang2024_2dgs_p1_b9.png)

![Image block](images/huang2024_2dgs_p1_b10.png)

(a) 2D disks as surface elements

![Image block](images/huang2024_2dgs_p1_b12.png)

![Image block](images/huang2024_2dgs_p1_b13.png)

(b) 2D Gaussian splatting

![Image block](images/huang2024_2dgs_p1_b15.png)

(c) Meshing

Fig. 1. Our method, 2DGS, (a) optimizes a set of 2D oriented disks to represent and reconstruct a complex real-world scene from multi-view RGB images. These optimized 2D disks are tightly aligned to the surfaces. (b) With 2D Gaussian splatting, we allow real-time rendering of high quality novel view images with view consistent normals and depth maps. (c) Finally, our method provides detailed and noise-free triangle mesh reconstruction from the optimized 2D disks.

3D Gaussian Splatting (3DGS) has recently revolutionized radiance field reconstruction, achieving high quality novel view synthesis and fast rendering speed. However, 3DGS fails to accurately represent surfaces due to the multi-view inconsistent nature of 3D Gaussians. We present 2D Gaussian Splatting (2DGS), a novel approach to model and reconstruct geometrically accurate radiance fields from multi-view images. Our key idea is to collapse the 3D volume into a set of 2D oriented planar Gaussian disks. Unlike 3D Gaussians, 2D Gaussians provide view-consistent geometry while modeling surfaces intrinsically. To accurately recover thin surfaces and achieve stable

optimization, we introduce a perspective-accurate 2D splatting process utilizing ray-splat intersection and rasterization. Additionally, we incorporate depth distortion and normal consistency terms to further enhance the quality of the reconstructions. We demonstrate that our differentiable renderer allows for noise-free and detailed geometry reconstruction while maintaining competitive appearance quality, fast training speed, and real-time rendering.

CCS Concepts: • **Computing methodologies** → Reconstruction; **Rendering**; Machine learning approaches.

Additional Key Words and Phrases: Novel View Synthesis, Radiance Fields, Surface Splatting, Surface Reconstruction

## ACM Reference Format:

Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger, and Shenghua Gao. 2024. 2D Gaussian Splatting for Geometrically Accurate Radiance Fields. In Special Interest Group on Computer Graphics and Interactive Techniques Conference Conference Papers ’24 (SIGGRAPH Conference Papers ’24), July 27-August 1, 2024, Denver, CO, USA. ACM, New York, NY, USA, 13 pages. [https://doi.org/10.1145/3641519.3657428](https://doi.org/10.1145/3641519.3657428)

<small><span class="docvortex-page-footnote" data-block-type="page_footnote" style="color:#6b7280">Authors’ Contact Information: Binbin Huang, huangbb@shanghaitech.edu.cn, ShanghaiTech University, Shanghai, China; Zehao Yu, zehao.yu@uni-tuebingen.de, University of Tübingen and Tübingen AI Center, Tübingen, Germany; Anpei Chen, anpei.chen@uni-tuebingen.de, University of Tübingen and Tübingen AI Center, Tübingen, Germany; Andreas Geiger, a.geiger@uni-tuebingen.de, University of Tübingen and Tübingen AI Center, Tübingen, Germany; Shenghua Gao, gaoshh@shanghaitech.edu.cn, ShanghaiTech University, Shanghai, China.</span></small>

## 1 INTRODUCTION

Photorealistic novel view synthesis (NVS) and accurate geometry reconstruction stand as pivotal long-term objectives in computer graphics and vision. Recently, 3D Gaussian Splatting (3DGS) [Kerbl

Permission to make digital or hard copies of all or part of this work for personal or classroom use is granted without fee provided that copies are not made or distributed for profit or commercial advantage and that copies bear this notice and the full citation on the first page. Copyrights for third-party components of this work must be honored. For all other uses, contact the owner/author(s). SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA © 2024 Copyright held by the owner/author(s). ACM ISBN 979-8-4007-0525-0/24/07 [https://doi.org/10.1145/3641519.3657428](https://doi.org/10.1145/3641519.3657428)

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 2 of 13 -->

2

Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger, and Shenghua Gao

et al. 2023] has emerged as an appealing alternative to implicit [Barron et al. 2022a; Mildenhall et al. 2020] and feature grid-based representations [Barron et al. 2023; Müller et al. 2022] in NVS, due to its real-time photorealistic NVS results at high resolutions. Rapidly evolving, 3DGS has been quickly extended with respect to multiple domains, including anti-aliasing rendering [Yu et al. 2024], material modeling [Jiang et al. 2023; Shi et al. 2023], dynamic scene reconstruction [Yan et al. 2023], and animatable avatar creation [Qian et al. 2023; Zielonka et al. 2023]. Nevertheless, it falls short in capturing intricate geometry since the volumetric 3D Gaussian, which models the complete angular radiance, conflicts with the thin nature of surfaces.

On the other hand, earlier works [Pfister et al. 2000; Zwicker et al. 2001a,b] have shown surfels (surface elements) to be an effective representation of complex geometry. Surfels approximate the object surface locally with shape and shade attributes and can be derived from known geometry. They are widely used in SLAM [Whelan et al. 2016] and other robotics tasks [Schöps et al. 2019] as an efficient geometry representation. Subsequent advancements [Yifan et al. 2019] have incorporated surfels into a differentiable framework. However, these methods typically require ground truth (GT) geometry, depth sensor data, or operate under constrained scenarios with known lighting.

Inspired by these works, we propose 2D Gaussian Splatting for 3D scene reconstruction and novel view synthesis that combines the benefits of both worlds, while overcoming their limitations. Unlike 3DGS, our approach represents a 3D scene with 2D Gaussian primitives, each defining an oriented elliptical disk. The significant advantage of 2D Gaussian over its 3D counterpart lies in the accurate geometry representation during rendering. Specifically, 3DGS evaluates a Gaussian’s value at the intersection between a pixel ray and a 3D Gaussian [Keselman and Hebert 2022, 2023], which leads to inconsistency depth when rendered from different viewpoints. In contrast, our method utilizes explicit ray-splat intersection, resulting in a perspective correct splatting, as illustrated in Figure 2, which in turn significantly improves reconstruction quality. Furthermore, the inherent surface normals in 2D Gaussian primitives enable direct surface regularization through normal constraints. In contrast with surfels-based models [Pfister et al. 2000; Yifan et al. 2019; Zwicker et al. 2001a], our 2D Gaussians can be recovered from unknown geometry with gradient-based optimization.

While our 2D Gaussian approach excels in geometric modeling, optimizing solely with photometric losses can lead to noisy reconstructions, due to the inherently unconstrained nature of 3D reconstruction tasks, as noted in [Barron et al. 2022b; Yu et al. 2022b; Zhang et al. 2020]. To enhance reconstructions and achieve smoother surfaces, we introduce two regularization terms: depth distortion and normal consistency. The depth distortion term concentrates 2D primitives distributed within a tight range along the ray, addressing the rendering process’s limitation where the distance between Gaussians is ignored. The normal consistency term minimizes discrepancies between the rendered normal map and the gradient of the rendered depth, ensuring alignment between the geometries defined by depth and normals. Employing these regularizations in combination with our 2D Gaussian model enables us to extract highly accurate surface meshes, as demonstrated in Figure 1.

![Image block](images/huang2024_2dgs_p2_b7.png)

Fig. 2. Comparison of 3DGS and 2DGS. 3DGS utilizes different intersection planes for value evaluation when viewing from different viewpoints, resulting in inconsistency. Our 2DGS provides multi-view consistent value evaluations.

In summary, we make the following contributions:

• We present a highly efficient differentiable 2D Gaussian renderer, enabling perspective-correct splatting by leveraging 2D surface modeling, ray-splat intersection, and volumetric integration.

• We introduce two regularization losses for improved and noise-free surface reconstruction.

• Our approach achieves state-of-the-art geometry reconstruction and NVS results compared to other explicit representations.

## 2 RELATED WORK

## 2.1 Novel view synthesis

Significant advancements have been achieved in NVS, particularly since the introduction of Neural Radiance Fields (NeRF) [Mildenhall et al. 2021]. NeRF employs a multi-layer perceptron (MLP) to represent geometry and view-dependent appearance, optimized via volume rendering to deliver exceptional rendering quality. Post-NeRF developments have further enhanced its capabilities. For instance, Mip-NeRF [Barron et al. 2021] and subsequent works [Barron et al. 2022a, 2023; Hu et al. 2023] tackle NeRF’s aliasing issues. Additionally, the rendering efficiency of NeRF has seen substantial improvements through techniques such as distillation [Reiser et al. 2021; Yu et al. 2021] and baking [Chen et al. 2023a; Hedman et al. 2021; Reiser et al. 2023; Yariv et al. 2023]. Moreover, the training and representational power of NeRF have been enhanced using feature-grid based scene representations [Chen et al. 2022, 2023c; Fridovich-Keil et al. 2022; Liu et al. 2020; Müller et al. 2022; Sun et al. 2022a].

Recently, 3D Gaussian Splatting (3DGS) [Kerbl et al. 2023] has emerged, demonstrating impressive real-time NVS results. This method has been quickly extended to multiple domains [Xie et al. 2023; Yan et al. 2023; Yu et al. 2024; Zielonka et al. 2023]. In this work, we propose to “flatten” 3D Gaussians to 2D Gaussian primitives to better align their shape with the object surface. Combined with two novel regularization losses, our approach reconstructs surfaces more accurately than 3DGS while preserving its high-quality and real-time rendering capabilities.

## 2.2 3D reconstruction

3D Reconstruction from multi-view images has been a long-standing goal in computer vision. Multi-view stereo based methods [Schön berger et al. 2016; Yao et al. 2018; Yu and Gao 2020] rely on a modular

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 3 of 13 -->

2D Gaussian Splatting for Geometrically Accurate Radiance Fields

3

pipeline that involves feature matching, depth prediction, and $\mathbf { f u } \cdot$ sion. In contrast, recent neural approaches [Niemeyer et al. 2020; Yariv et al. 2020] represent surface implicitly via an MLP [Mescheder et al. 2019; Park et al. 2019] , extracting surfaces post-training via the Marching Cube algorithm. Further advancements [Oechsle et al. 2021; Wang et al. 2021; Yariv et al. 2021] integrated implicit surfaces with volume rendering, achieving detailed surface reconstructions from RGB images. These methods have been extended to large-scale reconstructions via additional regularization [Li et al. 2023; Yu et al. 2022a,b], and efficient reconstruction for objects [Wang et al. 2023]. Despite these impressive developments, efficient large-scale scene reconstruction remains a challenge. For instance, Neuralangelo [Li et al. 2023] requires 128 GPU hours for reconstructing a single scene from the Tanks and Temples Dataset [Knapitsch et al. 2017]. In this work, we introduce 2D Gaussian splatting, a method that significantly accelerates the reconstruction process. It achieves similar or slightly better results compared to previous implicit neural surface representations, while being an order of magnitude faster.

## 2.3 Differentiable Point-based Graphics

Differentiable point-based rendering [Aliev et al. 2020; Insafutdinov and Dosovitskiy 2018; Rückert et al. 2022; Wiles et al. 2020; Yifan et al. 2019] has been explored extensively due to its efficiency and flexibility in representing intricate structures. Notably, NPBG [Aliev et al. 2020] rasterizes point cloud features onto an image plane, subsequently utilizing a convolutional neural network for RGB image prediction. DSS [Yifan et al. 2019] focuses on optimizing oriented point clouds from multi-view images under known lighting conditions. Pulsar [Lassner and Zollhofer 2021] introduces a tilebased acceleration structure for more efficient rasterization. More recently, 3DGS [Kerbl et al. 2023] optimizes anisotropic 3D Gaussian primitives, demonstrating real-time photorealistic NVS results. Despite these advances, using point-based representations from unconstrained multi-view images remains challenging. In this paper, we demonstrate detailed surface reconstruction using 2D Gaussian primitives. We also highlight the critical role of additional regularization losses in optimization, showcasing their significant impact on the quality of the reconstruction.

## 2.4 Concurrent works

Since 3DGS [Kerbl et al. 2023] was introduced, it has been rapidly adapted across multiple domains. We now review the closest work in inverse rendering. These work [Gao et al. 2023; Jiang et al. 2023; Liang et al. 2023; Shi et al. 2023] extend 3DGS by modeling normals as additional attributes of 3D Gaussian primitives. Our approach, in contrast, inherently defines normals by representing the tangent space of the 3D surface using 2D Gaussian primitives, aligning them more closely with the underlying geometry. Additionally, the aforementioned works predominantly focus on estimating the material properties of the scene and evaluating their results for relighting tasks. Notably, none of these works specifically target surface reconstruction, the primary focus of our work.

We also highlight the distinctions between our method and concurrent works SuGaR [Guédon and Lepetit 2023] and NeuSG [Chen et al. 2023b]. Unlike SuGaR, which approximates 2D Gaussians with

3D Gaussians, our method directly employs 2D Gaussians, simplifying the process and enhancing the resulting geometry without additional mesh refinement. NeuSG optimizes 3D Gaussian primitives and an implicit SDF network jointly and extracts the surface from the SDF network, while our approach leverages 2D Gaussian primitives for surface approximation, offering a faster and concep tually simpler solution.

## 3 3D GAUSSIAN SPLATTING

Kerbl et al. [Kerbl et al. 2023] propose to represent 3D scenes with 3D Gaussian primitives and render images using differentiable volume splatting. Specifically, 3DGS explicitly parameterizes Gaussian primitives via 3D covariance matrix 𝚺 and their location p<sub>𝑘</sub>:

$$
\mathcal {G} (\mathbf {p}) = \exp (- \frac {1}{2} (\mathbf {p} - \mathbf {p} _ {k}) ^ {\top} \Sigma^ {- 1} (\mathbf {p} - \mathbf {p} _ {k}))\tag{1}
$$

where the covariance matrix $\Sigma = \mathbf { R } \mathbf { S } \mathbf { S } ^ { \top } \mathbf { R } ^ { \top }$ is factorized into a scaling matrix S and a rotation matrix R. To render an image, the 3D Gaussian is transformed into the camera coordinates with worldto-camera transform matrix W and projected to image plane via a local affine transformation J [Zwicker et al. 2001a]:

$$
\Sigma^ {'} = \mathbf {J} \mathbf {W} \Sigma \mathbf {W} ^ {\top} \mathbf {J} ^ {\top}\tag{2}
$$

By skipping the third row and column of $: \Sigma ^ { ' }$ , we obtain a 2D Gaussian $\dot { \mathcal { G } } ^ { 2 D }$ with covariance matrix $\Sigma ^ { 2 D }$ . Next, 3DGS [Kerbl et al. 2023] employs volumetric alpha blending to integrate alpha-weighted appearance from front to back:

$$
\mathbf {c} (\mathbf {x}) = \sum_ {k = 1} ^ {K} \mathbf {c} _ {k} \alpha_ {k} \mathcal {G} _ {k} ^ {2 D} (\mathbf {x}) \prod_ {j = 1} ^ {k - 1} (1 - \alpha_ {j} \mathcal {G} _ {j} ^ {2 D} (\mathbf {x}))\tag{3}
$$

where 𝑘 is the index of the Gaussian primitives, $\alpha _ { k }$ denotes the alpha values and $\mathbf { c } _ { k }$ is the view-dependent appearance. The attributes of 3D Gaussian primitives are optimized using a photometric loss.

Challenges in Surface Reconstruction. Reconstructing surfaces using 3D Gaussian modeling and splatting faces several challenges. First, the volumetric radiance representation of 3D Gaussians conflicts with the thin nature of surfaces. Second, 3DGS does not natively model surface normals, essential for high-quality surface reconstruction. Third, the rasterization process in 3DGS lacks multi-view consistency, leading to varied 2D intersection planes for different viewpoints [Keselman and Hebert 2023], as illustrated in Figure 2 (a). Additionally, using an affine matrix for transforming a 3D Gaussian into ray space only yields accurate projections near the center, compromising on perspective accuracy around surrounding regions [Zwicker et al. 2004]. Therefore, it often results in noisy reconstructions, as shown in Figure 5.

## 4 2D GAUSSIAN SPLATTING

To accurately reconstruct geometry while maintaining high-quality novel view synthesis, we present differentiable 2D Gaussian splatting (2DGS).

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 4 of 13 -->

4 • Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger, and Shenghua Gao

![Image block](images/huang2024_2dgs_p4_b2.png)

Fig. 3. Illustration of 2D Gaussian Splatting. 2D Gaussian Splats are elliptical disks characterized by a center point $\mathbf { p } _ { k } ,$ tangential vectors $\mathbf { t } _ { u }$ and $\mathbf { t } _ { v } ,$ and two scaling factors $( s _ { u }$ and $s _ { v } )$ control the variance. Their elliptical projections are sampled through the ray-splat intersection ( Section 4.2) and accumulated via alpha-blending in image space. 2DGS reconstructs surface attributes such as colors, depths, and normals through gradient descent.

## 4.1 Modeling

Unlike 3DGS [Kerbl et al. 2023], which models the entire angular radiance in a blob, we simplify the 3-dimensional modeling by adopting “flat” 2D Gaussians embedded in 3D space. With 2D Gaussian modeling, the primitive distributes densities within a planar disk, defining the normal as the direction of the steepest change of density. This feature enables better alignment with thin surfaces. While previous methods [Kopanas et al. 2021; Yifan et al. 2019] also utilize 2D Gaussians for geometry reconstruction, they require a dense point cloud or ground-truth normals as input. By contrast, we simultaneously reconstruct the appearance and geometry given only a sparse calibration point cloud and photometric supervision.

As illustrated in Figure 3, our 2D splat is characterized by its central point $\mathfrak { p } _ { k }$ , two principal tangential vectors $\mathbf { t } _ { u }$ and $\mathbf { t } _ { v } ,$ and a scaling vector $\mathbf { \boldsymbol { S } } = ( s _ { u } , s _ { v } )$ that controls the variances of the 2D Gaussian. Notice that the primitive normal is defined by two orthogonal tangential vectors $\mathbf { t } _ { w } = \mathbf { t } _ { u } \times \mathbf { t } _ { v }$ . We can arrange the orientation into a 3 × 3 rotation matrix $\mathbf { R } = [ \mathbf { t } _ { u } , \mathbf { t } _ { v } , \mathbf { t } _ { w } ]$ and the scaling factors into a $3 \times 3$ diagonal matrix S whose last entry is zero.

A 2D Gaussian is therefore defined in a local tangent plane in world space, which is parameterized:

$$
P (u, v) = \mathbf {p} _ {k} + s _ {u} \mathbf {t} _ {u} u + s _ {v} \mathbf {t} _ {v} v = \mathbf {H} (u, v, 1, 1) ^ {\mathrm{T}}\tag{4}
$$

$$
\text {where} \mathbf {H} = \left[ \begin{array}{c c c c} s _ {u} \mathbf {t} _ {u} & s _ {v} \mathbf {t} _ {v} & \mathbf {0} & \mathbf {p} _ {k} \\ 0 & 0 & 0 & 1 \end{array} \right] = \left[ \begin{array}{c c} \mathrm{RS} & \mathbf {p} _ {k} \\ \mathbf {0} & 1 \end{array} \right]\tag{5}
$$

where H $\in   4 \times 4$ is a homogeneous transformation matrix representing the geometry of the 2D Gaussian. For the point $\mathbf { u } = ( u , v )$ in 𝑢𝑣 space, its 2D Gaussian value can then be evaluated by standard Gaussian

$$
\mathcal {G} (\mathbf {u}) = \exp \left(- \frac {u ^ {2} + v ^ {2}}{2}\right)\tag{6}
$$

The center ${ \mathfrak { p } } _ { k } ,$ , scaling $( s _ { u } , s _ { v } )$ , and the rotation $( \mathbf { t } _ { u } , \mathbf { t } _ { v } )$ are learnable parameters. Following 3DGS [Kerbl et al. 2023], each 2D Gaussian primitive has opacity 𝛼 and view-dependent appearance 𝑐 parameterized with spherical harmonics.

## 4.2 Splatting

One common strategy for rendering 2D Gaussians is to project the 2D Gaussian primitives onto the image space using the affine approximation of the perspective projection [Zwicker et al. 2001a,b]. However, as noted in [Zwicker et al. 2004], this projection is only accurate at the center of the Gaussian and has increasing approximation error with increased distance to the center. To address this issue, Zwicker et al. proposed a formulation based on homogeneous coordinates. Specifically, projecting the 2D splat onto an image plane can be described by a general 2D-to-2D mapping in homogeneous coordinates. Let $\mathbf { W } \in 4 \times 4$ be the combined transformation matrix from world space to screen space. The screen space points are hence obtained by

$$
\mathbf {x} = (x z, y z, z, z) ^ {\mathrm{T}} = \mathbf {W} P (u, v) = \mathbf {W} \mathbf {H} (u, v, 1, 1) ^ {\mathrm{T}}\tag{7}
$$

where x represents a homogeneous ray emitted from the camera and passing through pixel (𝑥, 𝑦) and intersecting the splat at depth 𝑧. To rasterize a 2D Gaussian, Zwicker et al. proposed to project its conic into the screen space with an implicit method using $\mathbf { M } = ( \mathbf { W } \mathbf { H } ) ^ { - 1 }$ However, the inverse transformation introduces numerical instability, especially when the splat degenerates into a line segment (i.e., if it is viewed from the side). To address this issue, previous surface splatting rendering methods discard such ill-conditioned transformations using a predefined threshold [Zwicker et al. 2004]. However, such a scheme poses challenges within a differentiable rendering framework, as thresholding can lead to unstable optimization. To address this problem, we utilize an explicit ray-splat intersection inspired by [Sigg et al. 2006].

Ray-splat Intersection. We efficiently locate the ray-splat intersections by finding the intersection of three non-parallel planes, a method originally designed for specialized hardware [Weyrich et al. 2007]. Given an image coordinate $\mathbf { x } = ( x , y )$ , we parameterize the ray of a pixel in the projective space as the intersection of two orthogonal planes: the x-plane and the y-plane. Specifically, the x-plane is defined by a normal vector (−1, 0, 0) and an offset 𝑥. The x-plane can be represented as a 4D homogeneous plane $\mathbf { h } _ { x } = ( - 1 , 0 , 0 , x ) ^ { \mathrm { T } }$ Similarly, the y-plane is $\mathbf { h } _ { y } = ( 0 , - 1 , 0 , y ) ^ { \mathrm { T } }$ . Thus, the ray $\mathbf { x } = ( x , y )$ is determined by the intersection of the two planes.

Next, we transform both planes into the local coordinates of the 2D Gaussian primitives, the 𝑢𝑣-coordinate system. Note that transforming points on a plane using a transformation matrix M is equivalent to transforming homogeneous plane parameters using the inverse transpose $\mathbf { M } ^ { - \mathrm { T } }$ [Blinn 1977]. Therefore, applying $\mathbf { M } = ( \mathbf { W } \mathbf { H } ) ^ { - 1 }$ is equivalent to $( \mathbf { W } \mathbf { H } ) ^ { \mathrm { T } }$ , eliminating explicit matrix inversion and yielding:

$$
\mathbf {h} _ {u} = (\mathbf {W H}) ^ {\mathrm{T}} \mathbf {h} _ {x} \quad \mathbf {h} _ {v} = (\mathbf {W H}) ^ {\mathrm{T}} \mathbf {h} _ {y}\tag{8}
$$

As introduced in Section 4.1, points on the 2D Gaussian plane are represented as $( u , v , 1 , 1 )$ . At the same time, the intersection point should fall in the transformed 𝑥-plane and 𝑦-plane. Thus,

$$
\mathbf {h} _ {u} \cdot (u, v, 1, 1) ^ {\mathrm{T}} = \mathbf {h} _ {v} \cdot (u, v, 1, 1) ^ {\mathrm{T}} = 0\tag{9}
$$

This leads to an efficient solution for the intersection point u(x):

$$
u (\mathbf {x}) = \frac {\mathbf {h} _ {u} ^ {2} \mathbf {h} _ {v} ^ {4} - \mathbf {h} _ {u} ^ {4} \mathbf {h} _ {v} ^ {2}}{\mathbf {h} _ {u} ^ {1} \mathbf {h} _ {v} ^ {2} - \mathbf {h} _ {u} ^ {2} \mathbf {h} _ {v} ^ {1}} \quad v (\mathbf {x}) = \frac {\mathbf {h} _ {u} ^ {4} \mathbf {h} _ {v} ^ {1} - \mathbf {h} _ {u} ^ {1} \mathbf {h} _ {v} ^ {4}}{\mathbf {h} _ {u} ^ {1} \mathbf {h} _ {v} ^ {2} - \mathbf {h} _ {u} ^ {2} \mathbf {h} _ {v} ^ {1}}\tag{10}
$$

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 5 of 13 -->

2D Gaussian Splatting for Geometrically Accurate Radiance Fields

5

where $\mathbf { h } _ { u } ^ { i } , \mathbf { h } _ { v } ^ { i }$ are the 𝑖-th parameter of the 4D plane. Note that $\mathbf { h } _ { u } ^ { 3 }$ and $\mathbf { h } _ { v } ^ { 3 }$ are always zero according to Eq. 5. Once we obtain the local coordinates $( u , v )$ , we can calculate the depth 𝑧 of the intersected points using Eq. 7 and evaluate the Gaussian value with Eq. 6.

Degenerate Solutions. When a 2D Gaussian is observed from a slanted viewpoint, it degenerates to a line in screen space. Therefore, it might be missed during rasterization. To deal with these cases and stabilize optimization, we employ the object-space low-pass filter introduced in [Botsch et al. 2005]:

$$
\hat {\mathcal {G}} (\mathbf {x}) = \max \left\{\mathcal {G} (\mathbf {u} (\mathbf {x})), \mathcal {G} \left(\frac {\mathbf {x} - \mathbf {c}}{\sigma}\right) \right\}\tag{11}
$$

where $\mathbf { u } ( \mathbf { x } )$ is given by $\operatorname { E q . }$ 10 and c is the projection of center $\mathbf { p } _ { k } .$ Intuitively, $\hat { \mathcal { G } } ( \mathbf { x } )$ is lower-bounded by a fixed screen-space Gaussian low-pass filter with center c and radius 𝜎. In our experiments, we set $\sigma = \sqrt { 2 } / 2$ to ensure sufficient pixels are used during rendering.

Rasterization. We follow a similar rasterization process as in 3DGS [Kerbl et al. 2023]. First, a screen space bounding box is computed for each Gaussian primitive. Then, 2D Gaussians are sorted based on the depth of their center and organized into tiles based on their bounding boxes. Finally, volumetric alpha blending is used to integrate alpha-weighted appearance from front to back:

$$
\mathbf {c} (\mathbf {x}) = \sum_ {i = 1} \mathbf {c} _ {i} \alpha_ {i} \hat {\mathcal {G}} _ {i} (\mathbf {u} (\mathbf {x})) \prod_ {j = 1} ^ {i - 1} (1 - \alpha_ {j} \hat {\mathcal {G}} _ {j} (\mathbf {u} (\mathbf {x})))\tag{12}
$$

The iterative process is terminated when the accumulated opacity reaches saturation.

## 5 TRAINING

Our 2D Gaussian method, while effective in geometric modeling, can result in noisy reconstructions when optimized only with photometric losses, a challenge inherent to 3D reconstruction tasks [Barron et al. 2022b; Yu et al. 2022b; Zhang et al. 2020]. To mitigate this issue and improve the geometry reconstruction, we introduce two regularization terms: depth distortion and normal consistency.

Depth Distortion. Different from NeRF, 3DGS’s volume rendering doesn’t consider the distance between intersected Gaussian primitives. Therefore, spreading out Gaussians might result in a similar color and depth rendering. This is different from surface rendering, where rays intersect the first visible surface exactly once. To mitigate this issue, we take inspiration from Mip-NeRF360 [Barron et al. 2022a] and propose a depth distortion loss to concentrate the weight distribution along the rays by minimizing the distance between the ray-splat intersections:

$$
\mathcal {L} _ {d} = \sum_ {i, j} \omega_ {i} \omega_ {j} | z _ {i} - z _ {j} |\tag{13}
$$

where $\begin{array} { r } { \omega _ { i } \; = \; \alpha _ { i }   \hat { \mathcal { G } } _ { i } ( \mathbf { u } ( \mathbf { x } ) ) \prod _ { j = 1 } ^ { i - 1 } ( 1   -   \alpha _ { j }   \hat { \mathcal { G } } _ { j } ( \mathbf { u } ( \mathbf { x } ) ) ) } \end{array}$ is the blending weight of the 𝑖−th intersection and $z _ { i }$ is the depth of the intersection points. Unlike the distortion loss in Mip-NeRF360, where $z _ { i }$ is the distance between sampled points and is not optimized, our approach directly encourages the concentration of the splats by adjusting the intersection depth $z _ { i } .$ Note that we implement this regularization term efficiently with CUDA in a manner similar to [Sun et al. 2022b].

Normal Consistency. As our representation is based on 2D Gaussian surface elements, we must ensure that all 2D splats are locally aligned with the actual surfaces. In the context of volume rendering where multiple semi-transparent surfels may exist along the ray, we consider the actual surface at the median point of intersection $\mathbf { p } _ { S } ,$ where the accumulated opacity reaches 0.5. We then align the splats’ normal with the gradients of the depth maps as follows:

$$
\mathcal {L} _ {n} = \sum_ {i} \omega_ {i} (1 - \mathbf {n} _ {i} ^ {\mathrm{T}} \mathbf {N})\tag{14}
$$

where 𝑖 indexes over intersected splats along the ray, 𝜔 denotes the blending weight of the intersection point, n<sub>𝑖</sub> represents the normal of the splat that is oriented towards the camera, and N is the normal estimated by the gradient of the depth map. Specifically, N is computed with finite differences from nearby depth points as follows:

$$
\mathrm{N} (x, y) = \frac {\nabla_ {x} \mathrm{p} _ {s} \times \nabla_ {y} \mathrm{p} _ {s}}{| \nabla_ {x} \mathrm{p} _ {s} \times \nabla_ {y} \mathrm{p} _ {s} |}\tag{15}
$$

By aligning the splat normal with the estimated surface normal, we ensure that 2D splats locally approximate the actual object surface.

Final Loss. Finally, we optimize our model from an initial sparse point cloud using a set of posed images. We minimize the following loss function:

$$
\mathcal {L} = \mathcal {L} _ {c} + \alpha \mathcal {L} _ {d} + \beta \mathcal {L} _ {n}\tag{16}
$$

where $\mathcal { L } c$ is an RGB reconstruction loss combining $\mathcal { L } _ { 1 }$ with the D-SSIM term from [Kerbl et al. 2023], while $\mathcal { L } _ { d }$ and ${ \mathcal { L } } _ { n }$ are regularization terms. We set $\alpha = 1 0 0 0$ for bounded scenes, $\alpha = 1 0 0$ for unbounded scenes, and $\beta = 0 . 0 5$ for all scenes.

## 6 EXPERIMENTS

We now present evaluations of our 2D Gaussian Splatting reconstruction method, including appearance and geometry comparison with previous state-of-the-art implicit and explicit approaches. We then analyze the contribution of the proposed components.

## 6.1 Implementation

We implement our 2D Gaussian Splatting with custom CUDA kernels, building upon the framework of 3DGS [Kerbl et al. 2023]. We extend the renderer to output depth distortion maps, depth maps and normal maps for regularizations (See detailed computations in Appendices A and B of the supplemental material). During training, we increase the number of 2D Gaussian primitives following the adaptive control strategy in 3DGS. Since our method does not directly rely on the gradient of the projected 2D center, we hence project the gradient of 3D center $\mathfrak { p } _ { k }$ onto the screen space as an approximation. Similarly, we employ a gradient threshold of 0.0002 and remove splats with opacity lower than 0.05 every 3000 step. We conduct all the experiments on a single GTX RTX3090 GPU.

Mesh Extraction. To extract meshes from reconstructed 2D splats, we render depth maps of the training views using the depth value of the splats projected to the pixels and utilize truncated signed distance fusion (TSDF) to fuse the reconstruction depth maps, using Open3D [Zhou et al. 2018]. We set the voxel size to 0.004 and the truncated threshold to 0.02 during TSDF fusion. We also extend the

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 6 of 13 -->

6

Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger, and Shenghua Gao

Ground truth

![Image block](images/huang2024_2dgs_p6_b4.png)

Ours (color)

Ours (normal)

Ours

3DGS

SuGaR

Fig. 4. Visual comparisons (test-set view) between our method, 3DGS [Kerbl et al. 2023], and SuGaR [Guédon and Lepetit 2023] using scenes from an real-world dataset [Barron et al. 2022b]. Our method excels at synthesizing geometrically accurate radiance fields and surface reconstruction, outperforming 3DGS and SuGaR in capturing sharp edges and intricate details.

Table 1. Quantitative comparison on the DTU Dataset [Jensen et al. 2014]. Our 2DGS achieves the highest reconstruction accuracy among other methods and provides 100× speed up compared to the SDF based baselines.

<table><tr><td colspan="2"></td><td>24</td><td>37</td><td>40</td><td>55</td><td>63</td><td>65</td><td>69</td><td>83</td><td>97</td><td>105</td><td>106</td><td>110</td><td>114</td><td>118</td><td>122</td><td>Mean</td><td>Time</td></tr><tr><td rowspan="3">implicit</td><td>NeRF [Mildenhall et al. 2021]</td><td>1.90</td><td>1.60</td><td>1.85</td><td>0.58</td><td>2.28</td><td>1.27</td><td>1.47</td><td>1.67</td><td>2.05</td><td>1.07</td><td>0.88</td><td>2.53</td><td>1.06</td><td>1.15</td><td>0.96</td><td>1.49</td><td>&gt;12h</td></tr><tr><td>VolSDF [Yariv et al. 2021]</td><td>1.14</td><td>1.26</td><td>0.81</td><td>0.49</td><td>1.25</td><td>0.70</td><td>0.72</td><td>1.29</td><td>1.18</td><td>0.70</td><td>0.66</td><td>1.08</td><td>0.42</td><td>0.61</td><td>0.55</td><td>0.86</td><td>&gt;12h</td></tr><tr><td>NeuS [Wang et al. 2021]</td><td>1.00</td><td>1.37</td><td>0.93</td><td>0.43</td><td>1.10</td><td>0.65</td><td>0.57</td><td>1.48</td><td>1.09</td><td>0.83</td><td>0.52</td><td>1.20</td><td>0.35</td><td>0.49</td><td>0.54</td><td>0.84</td><td>&gt;12h</td></tr><tr><td rowspan="4">explicit</td><td>3DGS [Kerbl et al. 2023]</td><td>2.14</td><td>1.53</td><td>2.08</td><td>1.68</td><td>3.49</td><td>2.21</td><td>1.43</td><td>2.07</td><td>2.22</td><td>1.75</td><td>1.79</td><td>2.55</td><td>1.53</td><td>1.52</td><td>1.50</td><td>1.96</td><td>11.2 m</td></tr><tr><td>SuGaR [Guédon and Lepetit 2023]</td><td>1.47</td><td>1.33</td><td>1.13</td><td>0.61</td><td>2.25</td><td>1.71</td><td>1.15</td><td>1.63</td><td>1.62</td><td>1.07</td><td>0.79</td><td>2.45</td><td>0.98</td><td>0.88</td><td>0.79</td><td>1.33</td><td>~ 1h</td></tr><tr><td>2DGS-15k (Ours)</td><td>0.48</td><td>0.92</td><td>0.42</td><td>0.40</td><td>1.04</td><td>0.83</td><td>0.83</td><td>1.36</td><td>1.27</td><td>0.76</td><td>0.72</td><td>1.63</td><td>0.40</td><td>0.76</td><td>0.60</td><td>0.83</td><td>5.5 m</td></tr><tr><td>2DGS-30k (Ours)</td><td>0.48</td><td>0.91</td><td>0.39</td><td>0.39</td><td>1.01</td><td>0.83</td><td>0.81</td><td>1.36</td><td>1.27</td><td>0.76</td><td>0.70</td><td>1.40</td><td>0.40</td><td>0.76</td><td>0.52</td><td>0.80</td><td>10.9 m</td></tr></table>

Table 2. Quantitative results on the Tanks and Temples Dataset [Knapitsch et al. 2017]. We report the F1 score and training time.

|  | NeuS | Geo-Neus | Neurlangelo | SuGaR | 3DGS | Ours |
| --- | --- | --- | --- | --- | --- | --- |
| Barn | 0.29 | 0.33 | 0.70 | 0.14 | 0.13 | 0.41 |
| Caterpillar | 0.29 | 0.26 | 0.36 | 0.16 | 0.08 | 0.23 |
| Courthouse | 0.17 | 0.12 | 0.28 | 0.08 | 0.09 | 0.16 |
| Ignatius | 0.83 | 0.72 | 0.89 | 0.33 | 0.04 | 0.51 |
| Meetingroom | 0.24 | 0.20 | 0.32 | 0.15 | 0.01 | 0.17 |
| Truck | 0.45 | 0.45 | 0.48 | 0.26 | 0.19 | 0.45 |
| Mean | 0.38 | 0.35 | 0.50 | 0.19 | 0.09 | 0.32 |
| Time | >24h | >24h | >24h | >1h | 14.3 m | 15.5 m |

original 3DGS to render depth and employ the same technique for surface reconstruction for a fair comparison.

## 6.2 Comparison

Dataset. We evaluate the performance of our method on various datasets, including DTU [Jensen et al. 2014], Tanks and Temples [Knapitsch et al. 2017], and Mip-NeRF360 [Barron et al. 2022a]. The DTU dataset comprises 15 scenes, each with 49 or 69 images of

Table 3. Performance comparison between 2DGS (ours), 3DGS and SuGaR on the DTU dataset [Jensen et al. 2014]. We report the averaged chamfer distance, PSNR (training-set view), reconstruction time, and model size.

|  | CD ↓ | PSNR ↑ | Time ↓ | MB (Storage) ↓ |
| --- | --- | --- | --- | --- |
| 3DGS [Kerbl et al. 2023] | 1.96 | 35.76 | 11.2 m | 113 |
| SuGaR [Guédon and Lepetit 2023] | 1.33 | 34.57 | ∼1 h | 1247 |
| 2DGS-15k (Ours) | 0.83 | 33.42 | 5.5 m | 52 |
| 2DGS-30k (Ours) | 0.80 | 34.52 | 10.9 m | 52 |

resolution 1600 × 1200. We use Colmap [Schönberger and Frahm 2016] to generate a sparse point cloud for each scene and downsample the images into a resolution of 800 × 600 for efficiency. We use the same training process for 3DGS [Kerbl et al. 2023] and SuGaR [Guédon and Lepetit 2023] for a comparison.

Geometry Reconstruction. In Table 1 and Table 3, we compare our geometry reconstruction to SOTA implicit (i.e., NeRF [Mildenhall et al. 2020], VolSDF [Yariv et al. 2021], and NeuS [Wang et al. 2021]), explicit (i.e., 3DGS [Kerbl et al. 2023] and concurrent work SuGaR [Guédon and Lepetit 2023]) methods on Chamfer distance

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 7 of 13 -->

2D Gaussian Splatting for Geometrically Accurate Radiance Fields

7

![Image block](images/huang2024_2dgs_p7_b3.png)

Input

![Image block](images/huang2024_2dgs_p7_b5.png)

3DGS

![Image block](images/huang2024_2dgs_p7_b7.png)

![Image block](images/huang2024_2dgs_p7_b8.png)

Ours

Fig. 5. Qualitative comparison on the DTU benchmark [Jensen et al. 2014]. Our 2DGS produces detailed and noise-free surfaces.

Table 4. Quantitative results on Mip-NeRF 360 [Barron et al. 2022a] dataset. All scores of the baseline methods are directly taken from their papers whenever available. We report the performance of 3DGS, SuGaR and ours using 30𝑘 iterations.

|  | O PSNR ↑ | utdoor Sc SSIM ↑ | ene LIPPS ↓ | I PSNR ↑ | ndoor sce SSIM ↑ | ne LIPPS ↓ |
| --- | --- | --- | --- | --- | --- | --- |
| NeRF | 21.46 | 0.458 | 0.515 | 26.84 | 0.790 | 0.370 |
| Deep Blending | 21.54 | 0.524 | 0.364 | 26.40 | 0.844 | 0.261 |
| Instant NGP | 22.90 | 0.566 | 0.371 | 29.15 | 0.880 | 0.216 |
| MERF | 23.19 | 0.616 | 0.343 | 27.80 | 0.855 | 0.271 |
| BakedSDF | 22.47 | 0.585 | 0.349 | 27.06 | 0.836 | 0.258 |
| MipNeRF360 | 24.47 | 0.691 | 0.283 | 31.72 | 0.917 | 0.180 |
| Mobile-NeRF | 21.95 | 0.470 | 0.470 | - | - | - |
| SuGaR | 22.93 | 0.629 | 0.356 | 29.43 | 0.906 | 0.225 |
| 3DGS | 24.64 | 0.731 | 0.234 | 30.41 | 0.920 | 0.189 |
| 2DGS (Ours) | 24.34 | 0.717 | 0.246 | 30.40 | 0.916 | 0.195 |

and training time using the DTU dataset. Our method outperforms all compared methods in terms of Chamfer distance. Moreover, as shown in Table 2, 2DGS achieves competitive results with SDF models (i.e., NeuS [Wang et al. 2021] and Geo-Neus [Fu et al. 2022]) on the TnT dataset, and significantly better reconstruction than explicit reconstruction methods (i.e., 3DGS and SuGaR). Notably, our model demonstrates exceptional efficiency, offering a reconstruction speed that is approximately 100 times faster compared to implicit reconstruction methods and more than 3 times faster than the concurrent work SuGaR. Our approach can also achieve qualitatively better reconstructions with more appearance and geometry details and fewer outliers, as shown in Figure 5. Moreover, SDF-based reconstruction methods require predefining the spherical size for initialization, which plays a critical role in the success of SDF reconstruction. By contrast, our method leverages radiance field based geometry modeling and is less sensitive to initialization. We include the full geometry reconstruction results for both DTU and TnT in Figure 9 and Figure 10.

Appearance Reconstruction. Our method represents 3D scenes as radiance fields, providing high-quality novel view synthesis. In this section, we compare our novel view renderings using the Mip NeRF360 dataset against baseline approaches, as shown in Table 4 and Figure 4. Note that, since the ground truth geometry is not available in the Mip-NeRF360 dataset and we hence focus on quantitative comparison. Remarkably, our method consistently achieves

Table 5. Quantitative studies for the regularization terms and mesh extraction methods on the DTU dataset.

|  | Accuracy ↓ | Completion ↓ | Average ↓ |
| --- | --- | --- | --- |
| A. w/o normal consistency | 1.35 | 1.13 | 1.24 |
| B. w/o depth distortion | 0.89 | 0.87 | 0.88 |
| C. w / expected depth | 0.88 | 1.01 | 0.94 |
| D. w / SPSR | 1.25 | 0.89 | 1.07 |
| E. Full Model | 0.79 | 0.86 | 0.83 |

![Image block](images/huang2024_2dgs_p7_b17.png)

Input

![Image block](images/huang2024_2dgs_p7_b19.png)

(A) w/o. NC

![Image block](images/huang2024_2dgs_p7_b21.png)

(B) w/o. DD

![Image block](images/huang2024_2dgs_p7_b23.png)

Full Model

Fig. 6. Qualitative studies for the regularization effects. From left to right – input image, surface normals without normal consistency, without depth distortion, and our full model. Disabling the normal consistency loss leads to noisy surface orientations; conversely, omitting depth distortion regularization results in blurred surface normals. The complete model, employing both regularizations, successfully captures sharp and flat features.

competitive NVS results across state-of-the-art techniques while providing geometrically accurate surface reconstruction. We include the appearance rendering results in Figure 11.

## 6.3 Ablations

In this section, we isolate the design choices and measure their effect on reconstruction quality, including regularization terms and mesh extraction. We conduct experiments on the DTU dataset [Jensen et al. 2014] with 15𝑘 iterations and report the reconstruction accuracy, completeness and average reconstruction quality. The quantitative effect of the choices is reported in Table 5. Additional baseline comparisons can be found in Appendix C of the supplemental material.

Regularization. We first examine the effects of the proposed normal consistency and depth distortion regularization terms. Our model (Table 5 E) provides the best performance when applying both regularization terms. We observe that disabling the normal consistency (Table 5 A) can lead to incorrect orientation, as shown in Figure 6 A. Additionally, the absence of depth distortion (Table 5 B) results in a noisy surface, as shown in Figure 6 B.

Mesh Extraction. We now analyze our choice for mesh extraction. Our full model (Table 5 E) utilizes TSDF fusion for mesh extraction with median depth. One alternative option is to use the expected depth instead of the median depth. However, it yields worse reconstructions as it is more sensitive to outliers, as shown in Table 5 C. Further, our approach surpasses screened Poisson surface reconstruction (SPSR)(Table 5 D) [Kazhdan and Hoppe 2013] using 2D Gaussians’ center and normal as inputs, due to SPSR’s inability to incorporate the opacity and the size of 2D Gaussian primitives.

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 8 of 13 -->

8

• Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger, and Shenghua Gao

## 7 CONCLUSION

We presented 2D Gaussian splatting, a novel approach for geometrically accurate radiance field reconstruction. We utilized 2D Gaussian primitives for 3D scene representation, facilitating accurate and view consistent geometry modeling and rendering. We proposed two regularization techniques to further enhance the reconstructed geometry. Extensive experiments on several challenging datasets verify the effectiveness and efficiency of our method.

Limitations. While our method successfully delivers accurate appearance and geometry reconstruction for a wide range of objects and scenes, we also discuss its limitations: First, we assume surfaces with full opacity and extract meshes from multi-view depth maps. This can pose challenges in accurately handling semi-transparent surfaces, such as glass, due to their complex light transmission properties, as shown in Figure 12. Secondly, our current densification strategy favors texture-rich over geometry-rich areas, occasionally leading to less accurate representations of fine geometric structures. A more effective densification strategy could mitigate this issue. Finally, our regularization often involves a trade-off between image quality and geometry, and can potentially lead to over-smoothing in certain regions.

## ACKNOWLEDGMENTS

BH and SG are supported by NSFC #62172279, #61932020, Program of Shanghai Academic Research Leader. ZY, AC and AG are supported by the ERC Starting Grant LEGO-3D (850533) and DFG EXC number 2064/1 - project number 390727645.

## REFERENCES

Kara-Ali Aliev, Artem Sevastopolsky, Maria Kolos, Dmitry Ulyanov, and Victor Lempitsky. 2020. Neural point-based graphics. In Computer Vision–ECCV 2020: 16th European Conference, Glasgow, UK, August 23–28, 2020, Proceedings, Part XXII 16. Springer, 696–712.

Jonathan T. Barron, Ben Mildenhall, Matthew Tancik, Peter Hedman, Ricardo Martin-Brualla, and Pratul P. Srinivasan. 2021. Mip-NeRF: A Multiscale Representation for Anti-Aliasing Neural Radiance Fields. ICCV (2021).

Jonathan T Barron, Ben Mildenhall, Dor Verbin, Pratul P Srinivasan, and Peter Hedman. 2022a. Mip-nerf 360: Unbounded anti-aliased neural radiance fields. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. 5470–5479.

Jonathan T. Barron, Ben Mildenhall, Dor Verbin, Pratul P. Srinivasan, and Peter Hedman. 2022b. Mip-NeRF 360: Unbounded Anti-Aliased Neural Radiance Fields. CVPR (2022).

Jonathan T. Barron, Ben Mildenhall, Dor Verbin, Pratul P. Srinivasan, and Peter Hedman. 2023. Zip-NeRF: Anti-Aliased Grid-Based Neural Radiance Fields. ICCV (2023).

James F Blinn. 1977. A homogeneous formulation for lines in 3 space. In Proceedings of the 4th annual conference on Computer graphics and interactive techniques. 237–241.

Mario Botsch, Alexander Hornung, Matthias Zwicker, and Leif Kobbelt. 2005. Highquality surface splatting on today’s GPUs. In Proceedings Eurographics/IEEE VGTC Symposium Point-Based Graphics, 2005. IEEE, 17–141.

Anpei Chen, Zexiang Xu, Andreas Geiger, Jingyi Yu, and Hao Su. 2022. TensoRF: Tensorial Radiance Fields. In European Conference on Computer Vision (ECCV).

Hanlin Chen, Chen Li, and Gim Hee Lee. 2023b. NeuSG: Neural Implicit Surface Reconstruction with 3D Gaussian Splatting Guidance. arXiv preprint arXiv:2312.00846 (2023).

Zhiqin Chen, Thomas Funkhouser, Peter Hedman, and Andrea Tagliasacchi. 2023a. Mobilenerf: Exploiting the polygon rasterization pipeline for efficient neural field rendering on mobile architectures. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. 16569–16578.

Zhang Chen, Zhong Li, Liangchen Song, Lele Chen, Jingyi Yu, Junsong Yuan, and Yi Xu. 2023c. NeuRBF: A Neural Fields Representation with Adaptive Radial Basis Functions. In Proceedings of the IEEE/CVF International Conference on Computer Vision. 4182–4194.

Sara Fridovich-Keil, Alex Yu, Matthew Tancik, Qinhong Chen, Benjamin Recht, and Angjoo Kanazawa. 2022. Plenoxels: Radiance Fields without Neural Networks. In CVPR.

Qiancheng Fu, Qingshan Xu, Yew-Soon Ong, and Wenbing Tao. 2022. Geo-Neus: Geometry-Consistent Neural Implicit Surfaces Learning for Multi-view Reconstruction. Advances in Neural Information Processing Systems (NeurIPS) (2022).

Jian Gao, Chun Gu, Youtian Lin, Hao Zhu, Xun Cao, Li Zhang, and Yao Yao. 2023. Relightable 3D Gaussian: Real-time Point Cloud Relighting with BRDF Decomposition and Ray Tracing. arXiv:2311.16043 (2023).

Antoine Guédon and Vincent Lepetit. 2023. SuGaR: Surface-Aligned Gaussian Splatting for Efficient 3D Mesh Reconstruction and High-Quality Mesh Rendering. arXiv preprint arXiv:2311.12775 (2023).

Peter Hedman, Pratul P Srinivasan, Ben Mildenhall, Jonathan T Barron, and Paul Debevec. 2021. Baking neural radiance fields for real-time view synthesis. In Proceedings of the IEEE/CVF International Conference on Computer Vision. 5875–5884.

Wenbo Hu, Yuling Wang, Lin Ma, Bangbang Yang, Lin Gao, Xiao Liu, and Yuewen Ma. 2023. Tri-MipRF: Tri-Mip Representation for Efficient Anti-Aliasing Neural Radiance Fields. In ICCV.

Eldar Insafutdinov and Alexey Dosovitskiy. 2018. Unsupervised learning of shape and pose with differentiable point clouds. Advances in neural information processing systems 31 (2018).

Rasmus Jensen, Anders Dahl, George Vogiatzis, Engin Tola, and Henrik Aanæs. 2014. Large scale multi-view stereopsis evaluation. In Proceedings of the IEEE conference on computer vision and pattern recognition. 406–413.

Yingwenqi Jiang, Jiadong Tu, Yuan Liu, Xifeng Gao, Xiaoxiao Long, Wenping Wang, and Yuexin Ma. 2023. GaussianShader: 3D Gaussian Splatting with Shading Functions for Reflective Surfaces. arXiv preprint arXiv:2311.17977 (2023).

Michael Kazhdan and Hugues Hoppe. 2013. Screened poisson surface reconstruction. ACM Transactions on Graphics (ToG) 32, 3 (2013), 1–13.

Bernhard Kerbl, Georgios Kopanas, Thomas Leimkühler, and George Drettakis. 2023. 3D Gaussian Splatting for Real-Time Radiance Field Rendering. ACM Transactions on Graphics 42, 4 (July 2023). [https://repo-sam.inria.fr/fungraph/3d-gaussian-splatting/](https://repo-sam.inria.fr/fungraph/3d-gaussian-splatting/)

Leonid Keselman and Martial Hebert. 2022. Approximate differentiable rendering with algebraic surfaces. In European Conference on Computer Vision. Springer, 596–614.

Leonid Keselman and Martial Hebert. 2023. Flexible techniques for differentiable rendering with 3d gaussians. arXiv preprint arXiv:2308.14737 (2023).

Arno Knapitsch, Jaesik Park, Qian-Yi Zhou, and Vladlen Koltun. 2017. Tanks and Temples: Benchmarking Large-Scale Scene Reconstruction. ACM Transactions on Graphics 36, 4 (2017).

Georgios Kopanas, Julien Philip, Thomas Leimkühler, and George Drettakis. 2021. Point-Based Neural Rendering with Per-View Optimization. In Computer Graphics Forum, Vol. 40. Wiley Online Library, 29–43.

Christoph Lassner and Michael Zollhofer. 2021. Pulsar: Efficient sphere-based neural rendering. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. 1440–1449.

Zhaoshuo Li, Thomas Müller, Alex Evans, Russell H Taylor, Mathias Unberath, Ming-Yu Liu, and Chen-Hsuan Lin. 2023. Neuralangelo: High-Fidelity Neural Surface Reconstruction. In IEEE Conference on Computer Vision and Pattern Recognition (CVPR).

Zhihao Liang, Qi Zhang, Ying Feng, Ying Shan, and Kui Jia. 2023. GS-IR: 3D Gaussian Splatting for Inverse Rendering. arXiv preprint arXiv:2311.16473 (2023).

Lingjie Liu, Jiatao Gu, Kyaw Zaw Lin, Tat-Seng Chua, and Christian Theobalt. 2020. Neural Sparse Voxel Fields. NeurIPS (2020).

Jonathon Luiten, Georgios Kopanas, Bastian Leibe, and Deva Ramanan. 2024. Dynamic 3D Gaussians: Tracking by Persistent Dynamic View Synthesis. In 3DV.

Lars Mescheder, Michael Oechsle, Michael Niemeyer, Sebastian Nowozin, and Andreas Geiger. 2019. Occupancy Networks: Learning 3D Reconstruction in Function Space. In Conference on Computer Vision and Pattern Recognition (CVPR).

Ben Mildenhall, Pratul P. Srinivasan, Matthew Tancik, Jonathan T. Barron, Ravi Ramamoorthi, and Ren Ng. 2020. NeRF: Representing Scenes as Neural Radiance Fields for View Synthesis. In ECCV.

Ben Mildenhall, Pratul P Srinivasan, Matthew Tancik, Jonathan T Barron, Ravi Ramamoorthi, and Ren Ng. 2021. Nerf: Representing scenes as neural radiance fields for view synthesis. Commun. ACM 65, 1 (2021), 99–106.

Thomas Müller, Alex Evans, Christoph Schied, and Alexander Keller. 2022. Instant Neural Graphics Primitives with a Multiresolution Hash Encoding. ACM Trans. Graph. 41, 4, Article 102 (July 2022), 15 pages.

Michael Niemeyer, Lars Mescheder, Michael Oechsle, and Andreas Geiger. 2020. Differentiable Volumetric Rendering: Learning Implicit 3D Representations without 3D Supervision. In Conference on Computer Vision and Pattern Recognition (CVPR).

Michael Oechsle, Songyou Peng, and Andreas Geiger. 2021. UNISURF: Unifying Neural Implicit Surfaces and Radiance Fields for Multi-View Reconstruction. In International Conference on Computer Vision (ICCV).

Jeong Joon Park, Peter Florence, Julian Straub, Richard Newcombe, and Steven Lovegrove. 2019. DeepSDF: Learning Continuous Signed Distance Functions for Shape Representation. In The IEEE Conference on Computer Vision and Pattern Recognition (CVPR).

Hanspeter Pfister, Matthias Zwicker, Jeroen Van Baar, and Markus Gross. 2000. Surfels: Surface elements as rendering primitives. In Proceedings of the 27th annual conference

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 9 of 13 -->

2D Gaussian Splatting for Geometrically Accurate Radiance Fields

9

on Computer graphics and interactive techniques. 335–342.

Shenhan Qian, Tobias Kirschstein, Liam Schoneveld, Davide Davoli, Simon Giebenhain, and Matthias Nießner. 2023. GaussianAvatars: Photorealistic Head Avatars with Rigged 3D Gaussians. arXiv preprint arXiv:2312.02069 (2023).

Christian Reiser, Songyou Peng, Yiyi Liao, and Andreas Geiger. 2021. KiloNeRF: Speeding up Neural Radiance Fields with Thousands of Tiny MLPs. In International Conference on Computer Vision (ICCV).

Christian Reiser, Rick Szeliski, Dor Verbin, Pratul Srinivasan, Ben Mildenhall, Andreas Geiger, Jon Barron, and Peter Hedman. 2023. Merf: Memory-efficient radiance fields for real-time view synthesis in unbounded scenes. ACM Transactions on Graphics (TOG) 42, 4 (2023), 1–12.

Darius Rückert, Linus Franke, and Marc Stamminger. 2022. Adop: Approximate differentiable one-pixel point rendering. ACM Transactions on Graphics (ToG) 41, 4 (2022), 1–14.

Johannes Lutz Schönberger and Jan-Michael Frahm. 2016. Structure-from-Motion Revisited. In Conference on Computer Vision and Pattern Recognition (CVPR).

Johannes Lutz Schönberger, Enliang Zheng, Marc Pollefeys, and Jan-Michael Frahm. 2016. Pixelwise View Selection for Unstructured Multi-View Stereo. In European Conference on Computer Vision (ECCV).

Thomas Schöps, Torsten Sattler, and Marc Pollefeys. 2019. Surfelmeshing: Online surfel-based mesh reconstruction. IEEE transactions on pattern analysis and machine intelligence 42, 10 (2019), 2494–2507.

Yahao Shi, Yanmin Wu, Chenming Wu, Xing Liu, Chen Zhao, Haocheng Feng, Jingtuo Liu, Liangjun Zhang, Jian Zhang, Bin Zhou, Errui Ding, and Jingdong Wang. 2023. GIR: 3D Gaussian Inverse Rendering for Relightable Scene Factorization. Arxiv (2023). arXiv[:2312.05133](https://arxiv.org/abs/2312.05133)

Christian Sigg, Tim Weyrich, Mario Botsch, and Markus H Gross. 2006. GPU-based ray-casting of quadratic surfaces.. In PBG@ SIGGRAPH. 59–65.

Cheng Sun, Min Sun, and Hwann-Tzong Chen. 2022a. Direct Voxel Grid Optimization: Super-fast Convergence for Radiance Fields Reconstruction. In CVPR.

Cheng Sun, Min Sun, and Hwann-Tzong Chen. 2022b. Improved Direct Voxel Grid Optimization for Radiance Fields Reconstruction. arxiv cs.GR 2206.05085 (2022).

Peng Wang, Lingjie Liu, Yuan Liu, Christian Theobalt, Taku Komura, and Wenping Wang. 2021. NeuS: Learning Neural Implicit Surfaces by Volume Rendering for Multi-view Reconstruction. Advances in Neural Information Processing Systems 34 (2021), 27171–27183.

Yiming Wang, Qin Han, Marc Habermann, Kostas Daniilidis, Christian Theobalt, and Lingjie Liu. 2023. NeuS2: Fast Learning of Neural Implicit Surfaces for Multi-view Reconstruction. In Proceedings of the IEEE/CVF International Conference on Computer Vision (ICCV).

Tim Weyrich, Simon Heinzle, Timo Aila, Daniel B Fasnacht, Stephan Oetiker, Mario Botsch, Cyril Flaig, Simon Mall, Kaspar Rohrer, Norbert Felber, et al. 2007. A hardware architecture for surface splatting. ACM Transactions on Graphics (TOG) 26, 3 (2007), 90–es.

Thomas Whelan, Renato F Salas-Moreno, Ben Glocker, Andrew J Davison, and Stefan Leutenegger. 2016. ElasticFusion: Real-time dense SLAM and light source estimation. The International Journal of Robotics Research 35, 14 (2016), 1697–1716.

Olivia Wiles, Georgia Gkioxari, Richard Szeliski, and Justin Johnson. 2020. SynSin: End-to-end View Synthesis from a Single Image. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR).

Tianyi Xie, Zeshun Zong, Yuxing Qiu, Xuan Li, Yutao Feng, Yin Yang, and Chenfanfu Jiang. 2023. PhysGaussian: Physics-Integrated 3D Gaussians for Generative Dynamics. arXiv preprint arXiv:2311.12198 (2023).

Yunzhi Yan, Haotong Lin, Chenxu Zhou, Weijie Wang, Haiyang Sun, Kun Zhan, Xianpeng Lang, Xiaowei Zhou, and Sida Peng. 2023. Street Gaussians for Modeling Dynamic Urban Scenes. (2023).

Yao Yao, Zixin Luo, Shiwei Li, Tian Fang, and Long Quan. 2018. MVSNet: Depth Inference for Unstructured Multi-view Stereo. European Conference on Computer Vision (ECCV) (2018).

Lior Yariv, Jiatao Gu, Yoni Kasten, and Yaron Lipman. 2021. Volume rendering of neural implicit surfaces. Advances in Neural Information Processing Systems 34 (2021), 4805–4815.

Lior Yariv, Peter Hedman, Christian Reiser, Dor Verbin, Pratul P. Srinivasan, Richard Szeliski, Jonathan T. Barron, and Ben Mildenhall. 2023. BakedSDF: Meshing Neural SDFs for Real-Time View Synthesis. arXiv (2023).

Lior Yariv, Yoni Kasten, Dror Moran, Meirav Galun, Matan Atzmon, Basri Ronen, and Yaron Lipman. 2020. Multiview Neural Surface Reconstruction by Disentangling Geometry and Appearance. Advances in Neural Information Processing Systems 33 (2020).

Wang Yifan, Felice Serena, Shihao Wu, Cengiz Öztireli, and Olga Sorkine-Hornung. 2019. Differentiable surface splatting for point-based geometry processing. ACM Transactions on Graphics (TOG) 38, 6 (2019), 1–14.

Alex Yu, Ruilong Li, Matthew Tancik, Hao Li, Ren Ng, and Angjoo Kanazawa. 2021. PlenOctrees for Real-time Rendering of Neural Radiance Fields. In ICCV.

Zehao Yu, Anpei Chen, Bozidar Antic, Songyou Peng, Apratim Bhattacharyya, Michael Niemeyer, Siyu Tang, Torsten Sattler, and Andreas Geiger. 2022a. SDFStudio: A Unified Framework for Surface Reconstruction. [https://github.com/autonomousvision/sdfstudio](https://github.com/autonomousvision/sdfstudio)

Zehao Yu, Anpei Chen, Binbin Huang, Torsten Sattler, and Andreas Geiger. 2024. Mip-Splatting: Alias-free 3D Gaussian Splatting. Conference on Computer Vision and Pattern Recognition (CVPR) (2024).

Zehao Yu and Shenghua Gao. 2020. Fast-MVSNet: Sparse-to-Dense Multi-View Stereo With Learned Propagation and Gauss-Newton Refinement. In Conference on Computer Vision and Pattern Recognition (CVPR).

Zehao Yu, Songyou Peng, Michael Niemeyer, Torsten Sattler, and Andreas Geiger. 2022b. MonoSDF: Exploring Monocular Geometric Cues for Neural Implicit Surface Reconstruction. Advances in Neural Information Processing Systems (NeurIPS) (2022).

Kai Zhang, Gernot Riegler, Noah Snavely, and Vladlen Koltun. 2020. NeRF++: Analyzing and Improving Neural Radiance Fields. arXiv:2010.07492 (2020).

Qian-Yi Zhou, Jaesik Park, and Vladlen Koltun. 2018. Open3D: A Modern Library for 3D Data Processing. arXiv:1801.09847 (2018).

Wojciech Zielonka, Timur Bagautdinov, Shunsuke Saito, Michael Zollhöfer, Justus Thies, and Javier Romero. 2023. Drivable 3D Gaussian Avatars. (2023). arXiv[:2311.08581](https://arxiv.org/abs/2311.08581) [cs.CV]

Matthias Zwicker, Hanspeter Pfister, Jeroen Van Baar, and Markus Gross. 2001a. EWA volume splatting. In Proceedings Visualization, 2001. VIS’01. IEEE, 29–538.

Matthias Zwicker, Hanspeter Pfister, Jeroen Van Baar, and Markus Gross. 2001b. Surface splatting. In Proceedings of the 28th annual conference on Computer graphics and interactive techniques. 371–378.

Matthias Zwicker, Jussi Rasanen, Mario Botsch, Carsten Dachsbacher, and Mark Pauly. 2004. Perspective accurate splatting. In Proceedings-Graphics Interface. 247–254.

## A DETAILS OF DEPTH DISTORTION

While Barron et al. [Barron et al. 2022b] calculates the distortion loss with samples on the ray, we operate Gaussian primitives, where the intersected depth may not be ordered. To this end, we adopt an $\mathcal { L } _ { 2 }$ loss and transform the intersected depth 𝑧 to NDC space to down-weight distant Gaussian primitives, $m = \mathrm { N D C } ( z )$ , with near and far plane empirically set to 0.2 and 1000. We implemented our depth distortion loss based on [Sun et al. 2022b], also powered by tile-based rendering. Here we show that the nested algorithm can be implemented in a single forward pass:

$$
\begin{array}{r l} \mathcal {L} & = \sum_ {i = 0} ^ {N - 1} \sum_ {j = 0} ^ {i - 1} \omega_ {i} \omega_ {j} (m _ {i} - m _ {j}) ^ {2} \\ & = \sum_ {i = 0} ^ {N - 1} \omega_ {i} \left(m _ {i} ^ {2} \sum_ {j = 0} ^ {i - 1} \omega_ {j} + \sum_ {j = 0} ^ {i - 1} \omega_ {j} m _ {j} ^ {2} - 2 m _ {i} \sum_ {j = 0} ^ {i - 1} \omega_ {j} m _ {j}\right) \\ & = \sum_ {i = 0} ^ {N - 1} \omega_ {i} \left(m _ {i} ^ {2} A _ {i - 1} + D _ {i - 1} ^ {2} - 2 m _ {i} D _ {i - 1}\right), \end{array}\tag{17}
$$

where $\begin{array} { r } { A _ { i } = \sum _ { j = 0 } ^ { i } \omega _ { j } , D _ { i } = \sum _ { j = 0 } ^ { i } \omega _ { j } m _ { j } } \end{array}$ and $\begin{array} { r } { D _ { i } ^ { 2 } = \sum _ { j = 0 } ^ { i } \omega _ { j } m _ { j } ^ { 2 } . } \end{array}$

Specifically, we let $e _ { i } = \left( m _ { i } ^ { 2 } A _ { i - 1 } + D _ { i - 1 } ^ { 2 } - 2 m _ { i } D _ { i - 1 } \right)$ so that the distortion loss can be “rendered” as $\begin{array} { r } { \mathcal { L } _ { i } = \sum _ { j = 0 } ^ { i } \omega _ { j } e _ { j } } \end{array}$ . Here, $\mathcal { L } _ { i }$ measures the depth distortion up to the 𝑖-th Gaussian. During marching Gaussian front-to-back, we simultaneously accumulate $A _ { i } , D _ { i }$ and $D _ { i } ^ { 2 }$ , preparing for the next distortion computation $\mathcal { L } _ { i + 1 }$ . Similarly, the gradient of the depth distortion can be back-propagated to the primitives back-to-front. Different from implicit methods where 𝑚 are the pre-defined sampled depth and non-differentiable, we additionally back-propagate the gradient through the intersection 𝑚, encouraging the Gaussians to move tightly together directly.

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 10 of 13 -->

10

• Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger, and Shenghua Gao

Ground truth

![Image block](images/huang2024_2dgs_p10_b4.png)

![Image block](images/huang2024_2dgs_p10_b5.png)

Ours

![Image block](images/huang2024_2dgs_p10_b7.png)

3DGS

Fig. 7. Visualization of a plane tiled by 2D Gaussians. Affine approximation [Zwicker et al. 2001b] adopted in 3DGS [Kerbl et al. 2023] causes perspective distortion and inaccurate depth, violating normal consistency.

## B DEPTH CALCULATIONS

Mean depth: There are two optional depth computations used for our meshing process. The mean (expected) depth is calculated by weighting the intersected depth:

$$
z _ {\text {mean}} = \sum_ {i} \omega_ {i} z _ {i} / (\sum_ {i} \omega_ {i} + \epsilon)\tag{18}
$$

where $\omega _ { i } \; = \; T _ { i } \alpha _ { i } \hat { \mathcal { G } } _ { i } ( \mathbf { u } ( \mathbf { x } )$ is the weight contribution of the 𝑖-th Gaussian and $\begin{array} { r } { T _ { i }   =   \prod _ { j = 1 } ^ { i - 1 } \bigl ( 1 - \alpha _ { j }   \hat { \mathcal { G } } _ { j } ( \mathbf { u } ( \mathbf { x } ) ) \bigr ) } \end{array}$ measures its visibility. It is important to normalize the depth with the accumulated alpha $\begin{array} { r } { A = \sum _ { i } \omega _ { i } } \end{array}$ to ensure that a 2D Gaussian can be rendered as a planar 2D disk in the depth visualization.

Median depth: We compute the median depth as the largest “visible” depth, considering $T _ { i } = 0 . 5$ as the pivot for surface and free space:

$$
z _ {\mathrm{median}} = \max \{z _ {i} | T _ {i} > 0. 5 \},\tag{19}
$$

We find our median depth computation is more robust to [Luiten et al. 2024]. When a ray’s accumulated alpha does not reach 0.5, while Luiten et al. sets a default value of 15, our computation selects the last Gaussian, which is more accurate and suitable for training.

## C ADDITIONAL BASELINES

In this section, we present additional baselines to ablate the impact of our design choices, as summarized in Table 6. Furthermore, we integrate our meshing approach into the comparison against these baselines for a comprehensive analysis. SuGaR extracts a mesh from depth points utilizing SPSR (Screen Poisson Surface Reconstruction) during the coarse stage, followed by refinement using a mesh renderer. To assess the effect of this meshing strategy, we substituted SPSR with TSDF using the depth maps, followed by an identical refinement stage. However, we found that the depth map generated from their flat Gaussian intersection is sparse and discontinuous. As a result, the adaptation of TSDF with its discontinuous depth map yields inferior results. For 3DGS, we leverage SPSR for mesh generation. Because the 3D Gaussian lacks a surface normal, we treat its normal as a trainable parameter [Gao et al. 2023; Liang et al. 2023] distilled from the depth map, employing the normal consistency regularization. We then utilize all center points for SPSR, resulting in

Table 6. Additional baselines on DTU dataset. All the models are trained with 30𝑘 iterations.

|  | Accuracy ↓ | Completion ↓ | Average ↓ |
| --- | --- | --- | --- |
| SuGaR | 1.48 | 1.17 | 1.33 |
| SuGaR + TSDF | 2.47 | 1.90 | 2.18 |
| 3DGS + SPSR (center) | 2.05 | 1.25 | 1.65 |
| 3DGS + TSDF (mean) | 1.93 | 1.99 | 1.96 |
| 2DGS + SPSR (center) | 1.25 | 0.89 | 1.07 |
| 2DGS (affine approx) + TSDF (mean) | 0.96 | 1.20 | 1.08 |
| 2DGS (our rasterizer) + TSDF (mean) | 0.79 | 0.98 | 0.88 |
| 2DGS (our rasterizer) + TSDF (median) | 0.78 | 0.83 | 0.80 |

improved overall completion metrics compared to results obtained using TSDF.

Finally, we conduct ablation experiments on our 2DGS. Notably, 2DGS demonstrates enhanced performance by iteratively integrating components such as TSDF, perspective-correct rasterization, and median depth. For the affine approximation baseline, we utilize 3DGS’s rasterization method by configuring one scale of the 3D Gaussian to $1 e ^ { - 6 }$ . While affine approximation already yields promising results, integrating the proposed ray-splat intersection scheme results in more accurate depth map generation under perspective projection, as depicted in Figure 7, thus enhancing depth fusion performance.

## D ADDITIONAL RESULTS

Our 2D Gaussian Splatting method achieves comparable performance even without the need for regularizations, as Table 7 shows. We have included a detailed breakdown of per-scene metrics for the MipNeRF360 dataset [Barron et al. 2022b] in Table 9. Additionally, we have provided a comparison of our rendered depth maps with those from 3DGS and MipNeRF360 in Figure 8.

Table 7. PSNR scores for Synthetic NeRF dataset. Our model achieve comparable performance without using regularizations.

|  | Mic | Chair | Ship | Materials | Lego | Drums | Ficus | Hotdog | Mean |
| --- | --- | --- | --- | --- | --- | --- | --- | --- | --- |
| Plenoxels | 33.26 | 33.98 | 29.62 | 29.14 | 34.10 | 25.35 | 31.83 | 36.81 | 31.76 |
| INGP-Base | 36.22 | 35.00 | 31.10 | 29.78 | 36.39 | 26.02 | 33.51 | 37.40 | 33.18 |
| Mip-NeRF | 36.51 | 35.14 | 30.41 | 30.71 | 35.70 | 25.48 | 33.29 | 37.48 | 33.09 |
| 3DGS | 35.36 | 35.83 | 30.80 | 30.00 | 35.78 | 26.15 | 34.87 | 37.72 | 33.32 |
| Ours | 35.09 | 35.05 | 30.60 | 29.74 | 35.10 | 26.05 | 35.57 | 37.36 | 33.07 |

Table 8. PSNR scores for TnT dataset.

|  | Barn | Caterpillar | Courthouse | Ignatius | Meetingroom | Truck | Mean |
| --- | --- | --- | --- | --- | --- | --- | --- |
| SuGaR | 28.63 | 23.27 | 23.33 | 20.72 | 25.47 | 24.40 | 24.16 |
| 3DGS | 27.99 | 24.82 | 23.33 | 23.95 | 26.89 | 25.01 | 25.33 |
| Ours | 28.79 | 24.23 | 23.51 | 23.82 | 26.15 | 26.85 | 25.56 |

Table 9. PSNR↑, SSIM↑, LIPPS↓ scores for MipNeRF360 dataset.

|  | bicycle | flowers | garden | stump | treehill | room | counter | kitchen | bonsai | mean |
| --- | --- | --- | --- | --- | --- | --- | --- | --- | --- | --- |
| SugaR | 23.34 | 19.54 | 25.40 | 25.07 | 21.30 | 29.97 | 27.56 | 29.41 | 30.77 | 25.82 |
| 3DGS | 25.24 | 21.52 | 27.41 | 26.55 | 22.49 | 30.63 | 28.70 | 30.32 | 31.98 | 27.20 |
| Ours | 24.87 | 21.15 | 26.95 | 26.47 | 22.27 | 31.06 | 28.55 | 30.50 | 31.52 | 27.03 |
| SuGaR | 0.634 | 0.499 | 0.762 | 0.705 | 0.546 | 0.904 | 0.885 | 0.902 | 0.933 | 0.752 |
| 3DGS | 0.771 | 0.605 | 0.868 | 0.775 | 0.638 | 0.914 | 0.905 | 0.922 | 0.938 | 0.815 |
| Ours | 0.752 | 0.588 | 0.852 | 0.765 | 0.627 | 0.912 | 0.900 | 0.919 | 0.933 | 0.805 |
| SuGaR | 0.354 | 0.407 | 0.240 | 0.325 | 0.452 | 0.259 | 0.244 | 0.178 | 0.220 | 0.298 |
| 3DGS | 0.205 | 0.336 | 0.103 | 0.210 | 0.317 | 0.220 | 0.204 | 0.129 | 0.205 | 0.214 |
| Ours | 0.218 | 0.346 | 0.115 | 0.222 | 0.329 | 0.223 | 0.208 | 0.133 | 0.214 | 0.223 |

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 11 of 13 -->

2D Gaussian Splatting for Geometrically Accurate Radiance Fields

11

(a) Ground-truth

![Image block](images/huang2024_2dgs_p11_b4.png)

(b) MipNeRF360 [Barron et al. 2022b], SSIM=0.813

(c) 3DGS, normals from depth gradient

![Image block](images/huang2024_2dgs_p11_b7.png)

(e) Our model (2DGS), normals from depth gradient

![Image block](images/huang2024_2dgs_p11_b9.png)

(d) 3DGS [Kerbl et al. 2023], SSIM=0.834

(f ) Our model (2DGS), SSIM=0.845

Fig. 8. We visualize the depth maps generated by MipNeRF360 [Barron et al. 2022b], 3DGS [Kerbl et al. 2023], and our method. The depth maps for 3DGS (d) and 2DGS (f ) are rendered using Eq. 18 and visualized following MipNeRF360. To highlight the surface smoothness, we further visualize the normal estimated from depth gradient using Eq. 15 for both 3DGS (c) and ours (e). While MipNeRF360 is capable of producing plausibly smooth depth maps, its sampling process may result in the loss of detailed structures. Both 3DGS and 2DGS excel at modeling thin structures; however, as illustrated in (c) and (e), the depth map of 3DGS exhibits significant noise. In contrast, our approach generates sampled depth points with normals consistent with the rendered normal map (refer to Figure 1b), thereby enhancing depth fusion during the meshing process.

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 12 of 13 -->

12 • Binbin Huang, Zehao Yu, Anpei Chen, Andreas Geiger, and Shenghua Gao

![Image block](images/huang2024_2dgs_p12_b2.png)

Fig. 9. Comparison of surface reconstruction using our 2DGS and 3DGS [Kerbl et al. 2023]. Meshes are extracted by applying TSDF to the depth maps. SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.

<!-- page 13 of 13 -->

2D Gaussian Splatting for Geometrically Accurate Radiance Fields

13

![Image block](images/huang2024_2dgs_p13_b3.png)

Fig. 10. Qualitative studies for the Tanks and Temples dataset [Knapitsch et al. 2017].

![Image block](images/huang2024_2dgs_p13_b5.png)

![Image block](images/huang2024_2dgs_p13_b6.png)

Fig. 11. Appearance rendering results from reconstructed 2D Gaussian disks, including DTU, TnT, and Mip-NeRF360 datasets.

![Image block](images/huang2024_2dgs_p13_b8.png)

(A) Semi-transparent

![Image block](images/huang2024_2dgs_p13_b10.png)

![Image block](images/huang2024_2dgs_p13_b11.png)

(B) High light

Fig. 12. Illustration of limitations: Our 2DGS struggles with the accurate reconstruction of semi-transparent surfaces, for example, the glass shown in example (A). Moreover, our method tends to create holes in areas with high light intensity, as shown in (B).

SIGGRAPH Conference Papers ’24, July 27-August 1, 2024, Denver, CO, USA.