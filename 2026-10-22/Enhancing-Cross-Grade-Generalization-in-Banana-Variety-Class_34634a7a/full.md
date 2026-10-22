# Enhancing Cross-Grade Generalization in Banana Variety Classification via Hybrid CNN-Transformers and Knowledge Self-Distillation

Khush Kataruka<sup>1</sup>, Mohammad Muzammila<sup>1</sup>, Zahid Akhtar<sup>2</sup>,

<sup>1</sup>Department of Artificial Intelligence, Sardar Vallabhbhai National Institute of Technology, Surat, Gujarat, India.

<sup>2</sup>Electrical and Computer Engineering Department, State University of New York Polytechnic Institute, Utica, New York, USA.

<sup>3</sup>Department of Information Security and Communication Technology, Norwegian University of Science and Technology, Gjovik, Norway.

\*Corresponding author(s). E-mail(s): u23ai112@coed.svnit.ac.in; u23ai105@coed.svnit.ac.in; akhtarz@sunypoly.edu; raghavendra.ramachandra@ntnu.no; pkc@aid.svnit.ac.in;

## Abstract

In recent years, automated fruit classification systems have become a more critical component in precision agriculture for eficient yield estimation, quality control, and supply chain optimization. However, they still face significant challenges under varying quality, fruit maturity, illumination, texture degradation, morphological attributes, domain shift, and post-harvest handling conditions. In this study, we address the challenging issue of cross-grade banana variety classification. This is a real-world setting where models that have been trained on specific quality grades must generalize to unseen grades to handle significant domain shift. Under a rigorous Leave-One-Grade-Out (LOGO) evaluation protocol, we present a thorough comparative analysis of convolutional neural networks (CNNs), Vision Transformers (ViTs), and dual-stream hybrid architectures using a large scale dataset of 31,678 banana images with three varieties and three quality grades. Specifically, to address the drawbacks of single-paradigm frameworks, we present a dual-stream Swin ResNet hybrid framework enhanced with KL-divergence-based self-distillation to align probabilistic feature representations across the CNN and Transformer streams. Comprehensive experimental analyzes show that the presented hybrid framework with KL-divergence based

self-distillation achieves better overall performance, i.e., it attains a mean accuracy of 81.25% and significantly surpasses CNN and Transformer baseline models. Qualitative analysis further confirm that the hybrid framework in this study improves discriminative feature transferability, improves attention localization, and stabilizes optimization. Overall, the experimental results demonstrate how well hybrid distillation techniques can lead to domain robust agricultural systems and can be considered a promising direction for robust agricultural vision frameworks in the real world.

Keywords: Knowledge Self-Distillation , Leave-One-Grade-Out, Banana Classification, Vision Transformer

## 1 Introduction

Automated fruit variety classification is becoming increasingly vital in modern farming, as it supports large-scale yield estimation, quality control, and a smooth supply chain. But variations in growing regions, inconsistent cultivation practices, improper handling during harvest and distribution, inadequate disease and pest management make bananas susceptible to quality issues like bruising, peel discoloration, premature ripening, fungal lesions, splitting, shape deformities, and uneven coloration Al-Dairi et al. (2023). These imperfections significantly diminish retail value and marketability, resulting in substantial economic losses for producers and supply chain stakeholders Fernando et al. (2019). At present, the prevailing grading approach still depends heavily on manual inspection that sufers from low throughput, high labor costs and variable assessment criteria influenced by human subjectivity. Although mechanical sorting systems can enhance grading accuracy, they remain incapable of efectively assessing surface imperfections like bruising, spotting, or peel discoloration. Also, physical contact during sorting often results in secondary damage. These challenges and bananas being one of the world’s most vital staple crops (e.g., global production exceeding 114 million tonnes annually and serving as a primary food source for over 400 million people worldwide Yasin et al. (2025); Zhang et al. (2026)) have motivated extensive research into automated classification systems using machine learning and computer vision techniques Zhang et al. (2024).

Machine learning and computer vision-based automated classification systems ofer substantial benefits, such as increased processing speed, consistent quality evaluation, reduced labour costs, and enhanced traceability throughout the supply chain Zhang et al. (2024). Early techniques mainly employed hand-crafted features (e.g., color his tograms, texture descriptors) combined with classical machine learning algorithms such as Support Vector Machines (SVMs) and Random Forests. For example, the method in Zhuang et al. (2019); Santos Pereira et al. (2018) extracted peel color, local texture, and local shape features from diferent banana regions using local binary pattern (LBP) and classifying them using (Naive Bayes) NB, Linear Discriminant Analysis (LDA), and SVM algorithms Ghazal et al. (2021). While Fu et al. (2019) presented a multi-scale method that used VM and AdaBoost algorithms with fused LBP (local binary pattern) and HOG (histogram of oriented gradients) features. Nonetheless, these methods demonstrated limited generalization capability (i.e., failing to capture the complex hierarchical representations), especifically when confronting variations in lighting conditions, camera angles, and fruit quality grades.

With recent advances in computer vision and deep learning, intelligent inspection and sorting systems have emerged as a critical solution to overcoming these limitations. The deep learning algorithms have catalyzed a paradigm shift in agricultural automation, including fruit quality assessment and variety classification. In particular, Convolutional Neural Networks (CNNs) have revolutionized computer vision tasks by enabling automatic feature extraction directly from raw image data Li et al. (2021). CNNs have demonstrated exceptional success across various agricultural applications, including crop disease detection, fruit ripeness assessment, and variety classification Wallelign et al. (2018); Olisah et al. (2024); Gurjar et al. (2026); Ponce et al. (2019). For instance, the study in Sheikh et al. (2025); XU2 (2026) employed deep convolutional features learned from banana images using a transfer learning framework. Specifically, a fine-tuned deep learning classifier was used to distinguish banana varieties based on shape, color, and texture cues captured in the learned feature maps. While, the work in Shuprajhaa et al. (2023) proposed a CNN-XGBoost hybrid model for classifying banana ripening stages, where a convolutional neural network extracts deep visual features such as color, texture, and shape, and XGBoost performs the classification. Moreover, the proposed system used Linear Discriminant Analysis (LDA) for dimensionality reduction, thereby enabling efective training with smaller datasets.

Despite remarkable advances in deep learning for automated classification of fruit and banana varieties, several crucial challenges remain inadequately addressed Too et al. (2019); Mehdipour et al. (2026); Sarode and Patil (2026). Most current models (e.g., CNNs, Vision Transformers (ViTs), or hybrid architectures) perform well on in-distribution data but struggle to generalize across domain shifts commonly encountered in real-world banana production and distribution as well as other agriculture settings. These shifts arise from variations in quality grades, maturity levels, lighting conditions, and camera setups, leading to substantial degradation in model performance when confronted with unseen distributions of visual or quality-grade features. CNNs, while efective at capturing local texture and shape information, often fail to model global structural relationships critical for distinguishing visually similar varieties. Conversely, ViTs capture long-range dependencies and global context but typically require large datasets and may underutilize local texture cues that remain discriminative under quality degradation. Hybrid approaches that combine the strengths of both paradigms show promise, yet their eficacy for cross-grade and cross-domain agricultural classification remains largely unexplored. Consequently, ensuring robust, reliable performance across diverse fruit quality conditions remains an open and pressing research problem in precision banana agriculture. All in all, not only do existing methods struggle to generalize when confronted with unseen quality grades (particularly in settings where inter-class diferences are subtle and intra-class variability is high), but the efectiveness of hybrid architectures that combine complementary strengths for cross-grade classification remains underexplored.

As deep learning and vision-based systems are increasingly being deployed in banana orchards, packing houses, and markets, robustness to variations in grades, lighting, maturity, and surface quality is as crucial as classification accuracy. Thus, in this work, we focus on cross-grade banana variety classification, a challenging yet practically relevant task. To address the limitations of single-paradigm models, we propose a dual-stream CNN-Transformer hybrid architecture augmented with KL-divergencebased distillation. By encouraging alignment between the predictive distributions of a Swin Transformer (teacher) and a ResNet-based CNN (student), the model learns grade-invariant representations that are more robust to domain shift. The primary novelty of this work lies not only in the proposed CNN-Transformer architecture, but also in establishing cross-grade generalisability as a distinct and practically meaningful evaluation problem for banana variety classification. This paper makes the following key contributions:

• We establish a Leave-One-Grade-Out (LOGO) cross-validation framework, in which each grade is completely held out during testing, providing a more realistic assessment of model robustness to unseen grades than conventional random splits.

• We systematically evaluate CNNs, Vision Transformers, and hybrid architectures under the LOGO protocol, thereby ofering one of the first large-scale studies of banana variety classification under a rigorous cross-grade evaluation protocol.

• We introduce a hybrid model integrating a Swin Transformer and ResNet backbone to leverage feature fusion to improve cross-grade generalization and outperform pure CNN or Transformer baselines.

• We propose a self-distillation mechanism that aligns probability distributions between architectural streams, significantly improving robustness on challenging domains and accelerating convergence.

• Through attention-based visualizations (Grad-CAM and Score-CAM), inter-stream alignment analysis, and training dynamics studies, we ofer in-depth insights into how hybrid representations and knowledge distillation jointly mitigate domain shift efects.

To the best of our knowledge, we present the first systematic investigation of banana variety classification under a rigorous cross-grade generalisation setting. The paper is organized as follows. Section 2 reviews related work, and Section 3 describes the dataset. Section 4 presents the problem formulation, our proposed hybrid architecture, and KL-divergence-based feature alignment. Section 5 details the experimental analysis, including quantitative, interpretability, and qualitative results. Section 8 presents conclusions with future research directions.

## 2 Related Work

The utilization of computer vision (CV) and machine learning (ML) to horticultural variety classification has evolved considerably over the past two decades. CV and ML have been widely applied to fruit detection and classification tasks, including apple, mango, citrus, and banana varieties Too et al. (2019). In particular, most initial works in this field typically involved manual feature engineering, i.e., extracting local and texture characteristics, e.g., color histograms, image texture descriptors and shape features Liakos et al. (2018). For example, the study in Dittakan et al. (2017) extracted scale-invariant shape features and used a Bayesian-based classifier for banana cultivar classification. Other works include the use of geometrical, shape, and color features with discriminant analysis for corn variety recognition Chen et al. (2010), principal component analysis for basmati rice classification Kambo and Yerpude (2014), color statistical and texture features for tomato grading Arakeri and Lakshmana (2016), and morpho-colorimetric descriptors and LDA to classify plum varieties Sarigu et al. (2017). Such traditional ML based systems achievied moderate success under controlled settings but demonstrated lower robustness to environmental variations and required significant domain expertise for feature design.

The rise of deep learning reduced dependence on hand-crafted features and traditional machine learning classifiers. Researchers have successfully employed deep learning architectures for various fruit classification applications and achieved higher accuracy than traditional techniques. In particular, most studies have used CNNs as the dominant approach in agricultural image analysis Zangana et al. (2024). Models such as AlexNet, VGG, ResNet, and EficientNet have achieved strong performance in fruit defect detection, classification, and grading. For instance, authors in Al Haque et al. (2021) devised a CNN-based framework for strain detection and quality identification of bananas. The work in Dinata et al. (2021) utilised a CNN-based classification framework for strawberry plant disease detection. Recently, Vision Transformers (ViTs) have provided an alternative to CNNs by modeling self-attention mechanisms to model global dependencies in images and videos Mehdipour et al. (2025). Research studies have shown that ViTs can rival or exceed CNNs on some agriculture tasks. For instance, the study in Sharma and Vishwakarma (2024) classified banana plant leaves based on nutrient deficiency using a vision transformer. The problem of fine-grained, multi-defect classification for green plums was addressed using an improved vision transformer in Su et al. (2023). Nonetheless, Transformer-based frameworks usually require large-scale data and fail to assess cross-domain robustness.

Hybrid CNN-Transformer methods aim to integrate the complementary strengths of CNNs, which eficiently capture local texture features, and transformers, which model long-range dependencies Khan et al. (2023). Various fusion schemes, including early, late, and attention-based, have been developed to combine these paradigms. A hybrid CNN?Transformer model was proposed in Li et al. (2020) for multitemporal crop classification, where multisensor data are aligned and Transformer encoders are employed to capture temporal correlations. Furthermore, a framework that integrates local and global feature representations using a CNN?Transformer architecture was introduced in Tiwari et al. (2024). Similarly, Knowledge-distillation (KD), which was traditionally utilized for model compression, has been extended to feature alignment and cross-architecture learning Moslemi et al. (2024). KL-divergence has been widely employed to align probability distributions between teacher and student networks. The systems in Wang et al. (2025) used KD to train a lightweight MobileNetV3 with a ViT as the teacher for green plum defect classification. Despite the remarkable success of deep learning, including hybrid CNN?Transformer models and KD in other vision tasks, these approaches remain largely unexplored for agricultural generalization classification under cross-domain conditions. Thus, our work seeks to address this gap.

## 3 Dataset

This study used a comprehensive dataset consisting of 31,678 high-resolution banana images collected across three commercial varieties (i.e., Pachbale, Rasbale, and Elakkibale). Such varieties are mainly grown in South Asian agricultural regions Guru and N (2025). These varieties exhibit subtle morphological diferences that challenge both automated classification systems and human experts. Three quality grades (e.g., Grades 1: heavily blemished, 2: moderate defects, and 3: premium quality) are utilized to represent each variety. These grades do not reflect variety-specific attributes but rather diferences in ripeness, physical condition and marketability. Overall, the dataset is evenly balanced across varieties and grades (as detailed in Tables 1 and 2), ensuring that no single class dominates the training and evaluation.

As shown in Table $^ { 2 , }$ each quality grade comprises approximately 10,000 samples, resulting in a relatively uniform distribution across grades. This even distribution ensures that accuracy diferences largely come from domain shift rather than class imbalance. Grade 1 samples (i.e., 32.87%) show the highest visual noise and variability, and Grade 3 samples (i.e., 32.94%) are the most visually consistent and represent the easiest domain.

Table 1: Overall Dataset Statistics.
<table><tr><td>Variety</td><td>Count</td><td>Percentage</td></tr><tr><td>Pachbale</td><td>11,512</td><td>36.34%</td></tr><tr><td>Rasbale</td><td>10,112</td><td>31.92%</td></tr><tr><td>Elakki-bale</td><td>10,054</td><td>31.74%</td></tr><tr><td>Total</td><td>31,678</td><td>100.00%</td></tr></table>

## 4 Proposed Cross-Grade Banana Variety Classification Methodology

## 4.1 Problem Formulation

Under domain generalization, we formulate the cross-grade banana variety recognition as a multi-class classification problem. The objective is to accurately identify the banana variety samples that come from an unknown grade by acquiring samples that belong to specific quality grades. Let X and $Y = \mathrm { \{ P a c h b a l e \ } $ , Rasbale, Elakki-bale} denote the input sample space and set of variety labels, respectively. The dataset D is splited into three quality dependent domains, i.e., $D _ { 1 } , \ D _ { 2 }$ , and $D _ { 3 }$ matching to Grade 1, Grade 2, and Grade 3, respectively. More formally, let $D = \{ ( x _ { i } , y _ { i } , g _ { i } ) \} _ { i = 1 } ^ { N } .$

Table 2: Variety Distribution Across Quality Grades
<table><tr><td>Grade</td><td>Variety</td><td>Count</td><td>Percentage</td><td>Grade Total</td></tr><tr><td rowspan="3">Grade 1 (Heavily blemished)</td><td>Pachbale</td><td>3,807</td><td>36.56%</td><td rowspan="3">10,412</td></tr><tr><td>Rasbale</td><td>3,589</td><td>34.47%</td></tr><tr><td>Elakki-bale</td><td>3,016</td><td>28.97%</td></tr><tr><td rowspan="3">Grade 2 (Moderate defects)</td><td>Pachbale</td><td>3,944</td><td>36.42%</td><td rowspan="3">10,830</td></tr><tr><td>Elakki-bale</td><td>3,571</td><td>32.97%</td></tr><tr><td>Rasbale</td><td>3,315</td><td>30.61%</td></tr><tr><td rowspan="3">Grade 3 (Premium quality)</td><td>Pachbale</td><td>3,761</td><td>36.04%</td><td rowspan="3">10,436</td></tr><tr><td>Elakki-bale</td><td>3,467</td><td>33.22%</td></tr><tr><td>Rasbale</td><td>3,208</td><td>30.74%</td></tr></table>

where $x _ { i } \in \mathbb { R } ^ { H \times W \times 3 } , y _ { i } \in Y$ , and $g _ { i } \in \{ 1 , 2 , 3 \}$ indicate an RGB sample, variety label, and quality grade (domain), respectively.

The distribution shift across grades is the problem. The distributions of visual features $P ( X \mid Y , g )$ vary with g owing to diferences in ripeness, defects, texture, and surface appearance. As a result, a model that has been trained on one grade might not naturally generalize to another. The aim is to learn a classifier $f _ { \theta } : X \to Y$ utilizing training domains $G _ { \mathrm { t r a i n } } \subset \{ 1 , 2 , 3 \}$ so that it functions efectively on an unseen domain g<sub>test</sub> $\notin \ G _ { \mathrm { t r a i n } }$ . Thus, maximizing predictive accuracy on the held-out $D _ { \mathrm { t e s t } }$ is the goal, while only being able to access/train on samples from the $D _ { \mathrm { t r a i n } } .$ In this study, the Leave-One-Grade-Out (LOGO) protocol is used for evaluation. In every run, one grade is held out for testing, and the remaining grades are employed for training: $G _ { \mathrm { t r a i n } } = \{ 1 , 2 , 3 \} \setminus \{ g _ { \mathrm { t e s t } } \}$ . For example, if the system is being testing on grade 2 then it was trained on grades 1 and 3. This formulation difers from standard supervised classification, where the training and test samples are assumed to come from the same distribution. The cross-grade scenarios give a more realistic picture of what actually happens in the real-world agriculture. The systems have to handle and remain reliable across a wide range of quality diferences, including grades that were not part of the training set. This approach actually captures that challenge.

## 4.2 Baselines Architectures

In this study, to establish solid reference points, three popular vision paradigms (i.e., ResNet50 He et al. (2016), EficientNet-B1 Tan and Le (2019), and Swin Transformer Liu et al. (2021)) were evaluated as baselines. Under the same training conditions, all models were fine-tuned on the banana classification dataset after being initialized with ImageNet pre-trained weights. ResNet50 is the main CNN baseline. Its residual skip connections allow for stable deep network optimization and mitigate vanishing gradient problems. The model comprises four residual stages with gradually increasing channel dimensions, global average pooling, and a task-specific classifier. EficientNet-B1 provides a parameter-eficient CNN comparison. It is based on compound scaling that balances input resolution, network width, and depth. Compared with conventional CNNs, the architecture ofers robust trade-ofs between accuracy and eficiency by using MBConv blocks with squeeze-and-excitation modules. Swin Transformer Base portrays the transformer family. Unlike standard Vision Transformers, Swin uses shifted-window self-attention and hierarchical patch merging to capture long-range dependencies at a lower computational cost. The base configuration utilizes four stages with progressively larger embedding dimensions. It is worth noting that the models are initialized with ImageNet-V2 (for ResNet50 and EficientNet-B1) and ImageNet-1K (for Swin Transformer) pretrained weights and fine-tuned on the banana dataset.

## 4.3 Hybrid Teacher-Student Framework with KL-Divergence Distillation

To overcome the drawbacks of uni-paradigm architectures under cross-grade domain shift, we formulate a unified and dual-stream teacher?student hybrid framework which combines a Swin Transformer-based global representation learner with a ResNet50- based local feature extractor. Namely, the developed framework integrates global contextual relationships via a transformer and local texture patterns via CNNs. The architecture comprises six main parts: a Swin-Tiny teacher network, a ResNet50 student network, a learnable feature adaptor, dual classification heads, logit-level fusion, and a joint supervision and distillation objective. Two variations of the designed architecture were created in order to improve generalization and encourage coherent learning between the streams, i.e., a standard hybrid mechanism trained with crossentropy loss on fused outputs alone, and a KL-distillation hybrid mechanism that additionally incorporates a KL divergence alignment term between the two streams.

In the proposed architecture, the same input sample is processed by two parallel backbones. i.e., teacher branch (Swin Transformer as global representation learner) and student branch (ResNet50 as local feature extractor). Given an input image $x \in \mathbb { R } ^ { 2 2 4 \times 2 2 4 \times 3 }$ and ground-truth label $y \in \{ 1 , \ldots , C \}$ , the goal is to learn a robust predictive function by combining complementary high-level representations extracted by two branches separately. In fact, the transformer and CNN branches, respectively, focus on global context and long-range dependencies and fine-grained texture and shape cues robust to quality degradation.

## 4.3.1 Teacher Network: Swin-Tiny Transformer Branch

The teacher network is constructed using the Swin-Tiny Transformer, a hierarchical vision Transformer that operates on non-overlapping patch embeddings and passes them through multiple Swin-Tiny Transformer stages. An input image $\boldsymbol { x } \in \mathbb { R } ^ { 2 2 4 \times 2 2 4 \times 3 }$ prior to being linearly projected into token embeddings, the image is first divided into patches:

$$
z _ { i } ^ { ( 0 ) } = W _ { p } p _ { i } + b _ { p } ,\tag{1}
$$

where $p _ { i }$ is the i-th image patch, $W _ { p }$ is the linear projection weight, and $b _ { p }$ is the bias. These tokens go through L Swin-Tiny Transformer stages, where windowed selfattention and shifted-window attention are applied at each stage to obtain multi-scale

and hierarchical global context:

$$
z ^ { ( l + 1 ) } = \mathrm { S w i n – T i n y ~ B l o c k } \big ( z ^ { ( l ) } \big ) , \quad l = 0 , \ldots , L - 1 .\tag{2}
$$

The teacher feature vector is obtained by Global Average Pooling (GAP) over the outputs of the last stage:

$$
F _ { T } = \mathrm { G A P } \big ( z ^ { ( L ) } \big ) \in \mathbb { R } ^ { d _ { T } } ,\tag{3}
$$

which generates teacher logits after being run via a linear classification head:

$$
z _ { T } = W _ { T } F _ { T } + b _ { T } ,\tag{4}
$$

where $W _ { T }$ and $b _ { T }$ are, respectively, the weights and bias of the classification head.

## 4.3.2 Student Network: ResNet50 Branch

The student network is constructed using ResNet50. It is a 50-layer residual CNN that excels at extracting local texture and shape attributes via hierarchical convolutions. The student network captures a feature vector via

$$
F _ { S } = S ( x ) , \quad F _ { S } \in \mathbb { R } ^ { d _ { S } } ,\tag{5}
$$

after global average pooling over the last residual block. As the CNN and Transformer feature spaces are diferent $( d _ { S } \ne d _ { T } )$ , to harmonize heterogeneous feature spaces, we present a learnable feature adaptor $A ( \cdot )$ which projects CNN features into the transformer feature space for semantic alignment:

$$
F _ { A } = A ( F _ { S } ) = W _ { A } F _ { S } + b _ { A } , \quad F _ { A } \in \mathbb { R } ^ { d _ { T } } ,\tag{6}
$$

where $F _ { S } \in \mathbb { R } ^ { d _ { S } } , d _ { S } , F _ { T } \mathbb { R } ^ { d _ { T } } , d _ { T } , F _ { A } \in \mathbb { R } ^ { d _ { T } } , W _ { A } \in \mathbb { R } ^ { d _ { T } }$ , and $b _ { A } \in \mathbb { R } ^ { d _ { T } }$ represent, respectively, feature vector from student branch, dimension of student feature vector, feature vector from teacher branch, dimension of teacher feature vector, adapted student feature mapped to teacher space, learnable linear projection matrix $( d _ { T } \times d _ { S } )$ ， and learnable bias vector $( d _ { T } )$ . This alignment enables stable joint optimization as well as meaningful interaction between the two streams. The student logits are further given by:

$$
\begin{array} { r } { z _ { S } = W _ { S } F _ { A } + b _ { S } , } \end{array}\tag{7}
$$

where $W _ { S }$ and $b _ { S }$ , respectively, are the parameters of the student classification head.

Figure 1 depicts the overall workflow of the proposed hybrid framework. The ResNet50 student and the Swin-Tiny Transformer teacher process the input image simultaneously. Their outputs are fused to generate the final prediction. During training, an auxiliary KL divergence path ensures. The figure illustrates how self-distillation and supervised learning work together within the framework.

![](images/9a5ac7067e613eed290eb981dded0a1723d0a5bfbf979a0696302f7eff3c393f.jpg)  
Fig. 1: Illustration of the KL Divergence-based distillation mechanism used to align feature distributions.

## 4.3.3 Logit-Level Fusion

Every branch?s classification head generates logits:

$$
z _ { T } = W _ { T } F _ { T } + b _ { T } , \qquad z _ { S } = W _ { S } F _ { A } + b _ { S } .\tag{8}
$$

To increase robustness, logit averaging is used:

$$
z _ { \mathrm { a v g } } = \frac { z _ { T } + z _ { S } } { 2 } .\tag{9}
$$

Softmax over the fused logits is used to obtain the final prediction:

$$
\hat { y } = \arg \operatorname* { m a x } \ \mathrm { S o f t m a x } ( z _ { \mathrm { a v g } } ) .\tag{10}
$$

## 4.3.4 KL-Divergence Self-Distillation

The main diference between the KL-distillation hybrid and the standard fusion hybrid is the addition of a feature-level KL-divergence loss that explicitly aligns the internal representations of the two branches during training. Instead of supervising only the fused output, this framework treats the Swin branch as a soft teacher whose intermediate feature distribution guides the student (ResNet50) branch, thereby performing intra-model self-distillation. As shown in Figure 1, both branches produce independent class logits which are averaged at inference time, while distillation operates at the feature level.

The teacher features $F _ { T }$ are produced by the Swin backbone. The student features $F _ { A }$ are the adapted ResNet features after passing through a multi-layer adaptor with a residual projection:

$$
F _ { A } = A ( F _ { S } ) + W _ { r } F _ { S }\tag{11}
$$

where $A ( \cdot )$ is the adaptor MLP and $W _ { r }$ is the residual projection. Temperature scaling $T$ is applied to these feature vectors to produce soft distributions for the KL divergence:

$$
p _ { T } ^ { ( T ) } = \mathrm { S o f t m a x } \bigg ( \frac { F _ { T } } { T } \bigg ) , \qquad p _ { A } ^ { ( T ) } = \mathrm { L o g S o f t m a x } \bigg ( \frac { F _ { A } } { T } \bigg ) .\tag{12}
$$

The KL-divergence loss then measures how well the student feature distribution matches the teacher’s, scaled by $T ^ { 2 }$ to compensate for the gradient reduction introduced by temperature scaling:

$$
\mathcal { L } _ { \mathrm { K L } } = T ^ { 2 } \cdot D _ { \mathrm { K L } } \Big ( p _ { A } ^ { ( T ) } \| p _ { T } ^ { ( T ) } \Big )\tag{13}
$$

Note that $F _ { T }$ is detached from the computation graph, so gradients from ${ \mathcal { L } } _ { \mathrm { K L } }$ only update the student branch, preventing the teacher from being pulled towards the student. Both branches are simultaneously supervised with cross-entropy against the ground-truth labels:

$$
\mathcal { L } _ { \mathrm { t o t a l } } = \mathcal { L } _ { \mathrm { C E } } ( z _ { T } , y ) + \mathcal { L } _ { \mathrm { C E } } ( z _ { S } , y ) + \alpha \mathcal { L } _ { \mathrm { K L } }\tag{14}
$$

where $z _ { T }$ and $z _ { S }$ are the teacher and student output logits respectively, y is the groundtruth label, and $\alpha = 0 . 5$ controls the strength of the distillation signal. This $\mathcal { L } _ { \mathrm { t o t a l } }$ is the final training loss used directly for backpropagation. The complete forward pass is:

$$
x  \{ \begin{array} { l } { \begin{array} { c } { F _ { T } = \mathrm { S w i n } ( x ) , } \\ { F _ { S } = \mathrm { R e s N e t } ( x ) , } \\ { F _ { A } = A ( F _ { S } ) + W _ { r } F _ { S } , } \\ { z _ { T } = \mathrm { H e a d } _ { T } ( F _ { T } ) , \quad z _ { S } = \mathrm { H e a d } _ { S } ( F _ { A } ) , } \\ { z _ { \mathrm { a v g } } = \displaystyle \frac { z _ { T } + z _ { S } } { 2 } , } \\ { \rule { 0 ex } { 5 ex } . } \end{array} } \end{array}\tag{15}
$$

At inference time, $z _ { \mathrm { a v g } }$ is used for the final class prediction. To assess the impact of this distillation objective, we compare two models sharing the same dual-stream architecture: the Standard hybrid, trained with cross-entropy on the concatenation-fused output only, and the KL-Distillation hybrid, trained with the inter-stream featurelevel KL loss in addition to both branch CE losses. This directly isolates the benefit of distributional alignment beyond feature fusion.

## 5 Experiments Setups

In this section, we present the experimental evaluation of the proposed Cross-Grade banana variety classification scheme.

## 5.1 Experimental Design

We implement a Leave-One-Grade-Out (LOGO) cross-validation strategy. Crucially, to ensure robust evaluation, models are not shared between experiments. For every architecture, three completely independent models are instantiated and trained from scratch for the specific grade combination.

Table 3: Experimental Configuration for Leave-One-Grade-Out (LOGO) Cross-Validation
<table><tr><td>Experiment</td><td>Training Grades</td><td>Test Grade</td><td>Train Size</td><td>Test Size</td></tr><tr><td>1</td><td>Grade 2 + Grade 3</td><td>Grade 1</td><td>19,139</td><td>10,412</td></tr><tr><td>2</td><td>Grade 1 + Grade 3</td><td>Grade 2</td><td>18,763</td><td>10,830</td></tr><tr><td>3</td><td>Grade 1 + Grade 2</td><td>Grade 3</td><td>19,117</td><td>10,436</td></tr></table>

## 5.2 Training Configuration

The models were trained for up to 50 epochs, with early stopping to mitigate overfitting. The early stopping criterion was configured with a patience of 7 epochs and a minimum improvement threshold (min delta = 0.001) monitored on the validation loss. Optimization was carried out using the AdamW optimizer with an initial learning rate of $1 \times 1 0 ^ { - 4 }$ . A batch size of 32 was adopted to balance computational eficiency and convergence stability. All experiments were conducted on a CUDA-enabled H100-NVL GPU to facilitate accelerated training and eficient model optimization.

## 6 Quantitative Results

## 6.1 Overall Model Comparison

Table 4 presents a comprehensive comparison of all evaluated architecture variants, including baseline convolutional and transformer models, as well as hybrid configurations. Among the baseline models, Swin-Tiny Transformer achieves the highest mean accuracy (0.7294) and mean F1-score (0.7118), outperforming ResNet50 and EficientNet-B1. Its hierarchical transformer architecture and shifted window selfattention must therefore be responsible for its stronger capacity to model both local texture irregularities and long-range contextual dependencies. Compared to convolution-only architectures, Swin-Tiny Transformer achieves stronger discriminative representations.

The hybrid Swin-ResNet (Standard - NoAug) model further improves performance, achieving a mean accuracy of 0.7746 and a mean F1-score of 0.7443. ResNet enhances local texture sensitivity, enabling precise detection of bruise boundaries and fungal edges, while Swin-Tiny Transformer provides global contextual modeling to capture ripening patterns and spatial irregularities. The fusion of local inductive bias with long-range attention increases feature diversity and improves inter-class separability, thereby improving classification performance.

Notably, the KL divergence-based hybrid variant, Swin-ResNet (KL), achieves the best overall performance with a mean accuracy of 0.8125 and a mean F1-score of 0.8035. It also records the highest best-case accuracy (0.9209) and maintains strong worst-case performance (0.7386), demonstrating improved robustness across runs. In contrast, the Swin-EficientNet (KL) variant does not achieve comparable gains, performing similarly to its baseline. Overall, the results highlight the efectiveness of hybrid architectures, particularly when enhanced with KL divergence-based regularization enforces semantic consistency, reduces feature redundancy, and improves probability calibration. This enhances inter-class separability and minority-class recall, resulting in a more robust, balanced classification.

Table 4: Comprehensive Performance Evaluation of CNN-Based Backbones and Hybrid Architectures under KL Divergence Settings (No Augmentation)
<table><tr><td>Model</td><td>Mean Acc.</td><td>Std Acc.</td><td>Mean F1</td><td>Best</td><td>Worst</td></tr><tr><td colspan="6">Baselines</td></tr><tr><td>ResNet50</td><td>0.6945</td><td>±0.0710</td><td>0.6597</td><td>0.7760</td><td>0.6465</td></tr><tr><td>EfficientNet-B1</td><td>0.7151</td><td>±0.0390</td><td>0.6837</td><td>0.7602</td><td>0.6922</td></tr><tr><td>ConvNeXt-Tiny</td><td>0.7413</td><td>±0.1155</td><td>0.6999</td><td>0.8711</td><td>0.6498</td></tr><tr><td>DenseNet-121</td><td>0.7858</td><td>±0.0536</td><td>0.7752</td><td>0.8362</td><td>0.7295</td></tr><tr><td>ViT-B/16</td><td>0.7581</td><td>±0.0940</td><td>0.7457</td><td>0.8338</td><td>0.6528</td></tr><tr><td>Swin-Tiny</td><td>0.7294</td><td>±0.0664</td><td>0.7118</td><td>0.7980</td><td>0.6654</td></tr><tr><td colspan="6">Hybrids (KL Divergence - NoAug)</td></tr><tr><td>Swin-ResNet (KL)</td><td>0.8125</td><td>±0.0946</td><td>0.8035</td><td>0.9209</td><td>0.7386</td></tr><tr><td>Swin-EfficientNet(KL)</td><td>0.7150</td><td>±0.0843</td><td>0.6850</td><td>0.8044</td><td>0.6370</td></tr><tr><td> $\mathrm { S w i n – C o n v N e X t ( K L ) }$ </td><td>0.7823</td><td>±0.1397</td><td>0.7543</td><td>0.9077</td><td>0.6317</td></tr><tr><td>Swin-DenseNet(KL)</td><td>0.7587</td><td>±0.1441</td><td>0.7165</td><td>0.9168</td><td>0.6347</td></tr><tr><td>ViT-B/16–ResNet(KL)</td><td>0.7711</td><td>±0.0595</td><td>0.7598</td><td>0.8257</td><td>0.7076</td></tr><tr><td>ViT-B/16–ConvNeXt(KL)</td><td>0.7623</td><td>±0.1283</td><td>0.7212</td><td>0.8931</td><td>0.6366</td></tr><tr><td>ViT-B/16-EfficientNet(KL)</td><td>0.7391</td><td>±0.0829</td><td>0.7116</td><td>0.8135</td><td>0.6498</td></tr><tr><td>ViT-B/16-DenseNet(KL)</td><td>0.7956</td><td>±0.0974</td><td>0.7850</td><td>0.8666</td><td>0.6846</td></tr></table>

Table 4 further highlights the relative performance gains achieved by the proposed hybrid variants. Compared to the strongest baseline, Swin-Tiny (mean accuracy: 0.7294), the Swin-ResNet (KL) model achieves an absolute improvement of 0.0831, corresponding to a relative accuracy gain of approximately 11.4%. In terms of F1- score, the improvement from 0.7118 to 0.8035 represents a relative gain of 12.9%. When compared to the standard hybrid Swin-ResNet (NoAug), the KL-regularized variant improves mean accuracy from 0.7746 to 0.8125, yielding a relative gain of 4.9%. The corresponding F1-score improvement (0.7443 to 0.8035) reflects an 8.0% relative increase, indicating that KL-based regularization contributes not only to higher accuracy but also to improved class-balanced performance. Relative to conventional CNN baselines, the gains are even more pronounced. Compared to ResNet50, the proposed Swin-ResNet (KL) achieves a 17.0% relative improvement in mean accuracy and outperforms EficientNet-B1 by approximately 13.6%. These consistent relative gains across multiple baselines reinforce the efectiveness of hybridization combined with KL divergence-based regularization in enhancing both predictive performance and generalization robustness.

Table 5: Performance Comparison Across Test Grades
<table><tr><td>Model</td><td>Test Grade</td><td>Accuracy</td><td>Precision</td><td>Recall</td><td>F1-Score</td></tr><tr><td rowspan="2">ResNet50</td><td>Grade1 Grade2</td><td>0.6465 0.6609</td><td>0.6511 0.6581</td><td>0.6465 0.6609</td><td>0.5907 0.6143</td></tr><tr><td>Grade3</td><td>0.7760</td><td>0.7893</td><td>0.7760</td><td>0.7741</td></tr><tr><td rowspan="2">EfficientNet-B1</td><td></td><td></td><td></td><td></td><td></td></tr><tr><td>Grade1</td><td>0.6930</td><td>0.7332</td><td>0.6930</td><td>0.6432</td></tr><tr><td rowspan="2"></td><td>Grade2 Grade3</td><td>0.6922 0.7602</td><td>0.7112 0.7682</td><td>0.6922 0.7602</td><td>0.6539</td></tr><tr><td></td><td></td><td></td><td></td><td>0.7540</td></tr><tr><td rowspan="2">ConvNeXt-Tiny</td><td>Grade1</td><td>0.6498</td><td>0.6385</td><td>0.6498</td><td>0.5677</td></tr><tr><td>Grade2 Grade3</td><td>0.7030 0.8711</td><td>0.8424 0.8766</td><td>0.7030</td><td>0.6628</td></tr><tr><td rowspan="2">DenseNet-121</td><td></td><td></td><td></td><td>0.8711</td><td>0.8693</td></tr><tr><td>Grade1 Grade2</td><td>0.7295 0.7915</td><td>0.7312 0.8467</td><td>0.7295</td><td>0.7050</td></tr><tr><td rowspan="2"></td><td>Grade3</td><td>0.8362</td><td>0.8599</td><td>0.7915 0.8362</td><td>0.7882 0.8323</td></tr><tr><td>Grade1</td><td>0.6528</td><td>0.6471</td><td>0.6528</td><td>0.6184</td></tr><tr><td rowspan="2">ViT-B/16</td><td>Grade2 Grade3</td><td>0.8338 0.7876</td><td>0.8760 0.7880</td><td>0.8338 0.7876</td><td>0.8357 0.7830</td></tr><tr><td>Grade1</td><td>0.6654</td><td>0.6930</td><td>0.6654</td><td>0.6176</td></tr><tr><td rowspan="2">Swin-Tiny Swin-ResNet (Standard)</td><td>Grade2 Grade3</td><td>0.7980 0.7249</td><td>0.8300 0.7265</td><td>0.7980 0.7249</td><td>0.7927 0.7252</td></tr><tr><td>Grade1</td><td>0.6758 0.7316</td><td>0.6837</td><td>0.6758</td><td>0.6167</td></tr><tr><td rowspan="2">Swin-ResNet (KL)</td><td>Grade2 Grade3</td><td>0.9163</td><td>0.8222 0.9208</td><td>0.7316 0.9163</td><td>0.6995 0.9166</td></tr><tr><td>Grade1 Grade2</td><td>0.7386 0.7781</td><td>0.7462 0.8451</td><td>0.7386</td><td>0.7243</td></tr><tr><td rowspan="2">Swin-EfficientNet (KL)</td><td>Grade3</td><td>0.9209</td><td>0.9237</td><td>0.7781 0.9209</td><td>0.7659 0.9203</td></tr><tr><td>Grade1 Grade2</td><td>0.6370 0.7037</td><td>0.6417 0.8102</td><td>0.6370</td><td>0.5844</td></tr><tr><td rowspan="2">Swin-ConvNeXt (KL)</td><td>Grade3</td><td>0.8044</td><td>0.8256</td><td>0.7037 0.8044</td><td>0.6671 0.8036</td></tr><tr><td>Grade1</td><td>0.6317 0.8074</td><td>0.5936</td><td>0.6317</td><td>0.5480</td></tr><tr><td rowspan="2"></td><td>Grade2 Grade3</td><td>0.9077</td><td>0.8738 0.9086</td><td>0.8074 0.9077</td><td>0.8077 0.9073</td></tr><tr><td>Grade1</td><td>0.6347</td><td>0.6142</td><td>0.6347</td><td>0.5365</td></tr><tr><td rowspan="2">Swin-DenseNet (KL)</td><td>Grade2 Grade3</td><td>0.7247</td><td>0.7970</td><td>0.7247</td><td>0.6968</td></tr><tr><td></td><td>0.9168 0.7076</td><td>0.9217 0.7097</td><td>0.9168</td><td>0.9164</td></tr><tr><td rowspan="2">ViT-B/16–ResNet (KL)</td><td>Grade1 Grade2</td><td>0.7799</td><td>0.8384</td><td>0.7076 0.7799</td><td>0.6876 0.7670</td></tr><tr><td>Grade3</td><td>0.8257</td><td>0.8283</td><td>0.8257</td><td>0.8248</td></tr><tr><td rowspan="2">ViT-B/16-ConvNeXt (KL)</td><td>Grade1 Grade2</td><td>0.6366 0.7572</td><td>0.5807 0.8539</td><td>0.6366 0.7572</td><td>0.5231 0.7469</td></tr><tr><td>Grade3</td><td>0.8931</td><td>0.8951</td><td>0.8931</td><td>0.8937</td></tr><tr><td rowspan="2">ViT-B/16-EfficientNet (KL)</td><td>Grade1 Grade2</td><td>0.6498 0.7540</td><td>0.6381 0.8463</td><td>0.6498 0.7540</td><td>0.5783 0.7472</td></tr><tr><td>Grade3</td><td>0.8135</td><td>0.8128</td><td>0.8135</td><td>0.8094</td></tr><tr><td rowspan="2">ViT-B/16-DenseNet (KL)</td><td></td><td></td><td></td><td></td><td></td></tr><tr><td>Grade1 Grade2</td><td>0.6846 0.8355</td><td>0.6936 0.8627</td><td>0.6846 0.8355</td><td>0.6573 0.8327</td></tr></table>

## 6.2 Grade-Specific Performance Comparison

Table 5 presents detailed performance metrics across three independent test grades, enabling a fine-grained evaluation of model generalization under varying data conditions. For Grade1, the KL-regularized Swin-ResNet achieves the highest performance across all evaluation metrics, attaining an accuracy of 0.7386 and an F1-score of 0.7243. This represents a notable improvement over conventional CNN baselines such as ResNet50 (0.6465 accuracy) and EficientNet-B1 (0.6930 accuracy), indicating stronger robustness in more challenging test scenarios. In Grade2, Swin-Tiny achieves competitive performance (0.7980 accuracy), while the proposed Swin-ResNet (KL) maintains strong results with an accuracy of 0.7781 and the highest precision (0.8451), suggesting improved discriminative capability and reduced false positives. The standard Swin-ResNet hybrid also demonstrates consistent gains over individual backbones, confirming the benefit of architectural hybridization.

Grade3 results show a clear dominance of hybrid architectures. Swin-ResNet (Standard) achieves 0.9163 accuracy, while the KL-regularized variant further improves to 0.9209 accuracy and 0.9203 F1-score, representing the best overall grade-specific performance. The consistently high recall values indicate strong class coverage and stable generalization under favorable data conditions. Across all grades, CNN-only baselines exhibit greater fluctuation in performance, particularly in Grade1 and Grade2. In contrast, the KL-based hybrid model maintains consistently strong results, demonstrating improved robustness across varying dificulty levels. These findings suggest that the integration of transformer representations with convolutional features, combined with KL divergence-based regularization, enhances both predictive accuracy and grade-wise stability.

Table 5 presents detailed performance metrics across three independent test grades, enabling a fine-grained evaluation of model generalization under varying data conditions.

For Grade1, the KL-regularized Swin-ResNet achieves the highest accuracy (0.7386) and F1-score (0.7243). Compared to the strongest baseline for this grade, EficientNet-B1 (0.6930 accuracy), this corresponds to a relative accuracy improvement of approximately 6.6%. Compared to ResNet50 (0.6465 accuracy), the improvement is approximately 14.2%. The F1-score gain over the best baseline (0.6432) represents a relative improvement of about 12.6%, highlighting enhanced class-balanced performance under more challenging conditions.

For Grade2, Swin-Tiny achieves the highest accuracy (0.7980). However, the proposed Swin-ResNet (KL) achieves 0.7781 accuracy and the highest precision (0.8451), indicating improved discriminative confidence. Compared to ResNet50 (0.6609 accuracy), the KL-based hybrid yields a relative improvement of approximately 17.7%, and compared to EficientNet-B1 (0.6922 accuracy), the improvement is approximately 12.4%. These results demonstrate consistent gains over CNN-based baselines.

In Grade3, hybrid architectures clearly dominate. The Swin-ResNet (KL) achieves the best performance with 0.9209 accuracy and 0.9203 F1-score. Relative to the strongest baseline for this grade (ResNet50 at 0.7760 accuracy), this corresponds to an 18.7% relative improvement in accuracy. Compared to Swin-Tiny (0.7249 accuracy), the gain is approximately 27.0%, highlighting the substantial benefit of hybridization and KL-based regularization under favorable data conditions.

Overall, the relative improvements across all grades confirm that the proposed KL-regularized hybrid architecture consistently enhances predictive accuracy, classbalanced performance, and grade-wise robustness compared to both CNN-only and transformer-only baselines.

## 6.3 Cross-Grade Generalization: Train-on-One-Grade Protocol

To further assess the cross-grade generalization capability of the proposed hybrid framework, we conducted an additional evaluation under a more stringent Train-on-One-Grade (T1G) protocol. Under this protocol, each model is trained exclusively on samples from a single quality grade and evaluated on each of the two remaining unseen grades independently. This extends the Leave-One-Grade-Out (LOGO) evaluation and examines whether the learned representations can generalize from a single source domain to multiple target domains simultaneously, capturing more extreme distribution shifts.

Table 6 reports the grade-wise and aggregate performance of the proposed Swin-ResNet (KL) and the Standard Swin-ResNet (Dual CE) variants under the T1G protocol.

Table 6: Cross-Grade Generalization Results under Train-on-One-Grade (T1G) Protocol
<table><tr><td>Model</td><td>Train Grade</td><td>Test Grade</td><td>Accuracy</td><td>Precision</td><td>Recall</td><td>F1-Score</td></tr><tr><td rowspan="6">Swin-ResNet (KL)</td><td>Grade1</td><td>Grade2</td><td>0.6044</td><td>0.4968</td><td>0.6044</td><td>0.5120</td></tr><tr><td>Grade1</td><td>Grade3</td><td>0.7756</td><td>0.7972</td><td>0.7756</td><td>0.7643</td></tr><tr><td>Grade2</td><td>Grade1</td><td>0.6177</td><td>0.4236</td><td>0.6177</td><td>0.4981</td></tr><tr><td>Grade2</td><td>Grade3</td><td>0.7220</td><td>0.8047</td><td>0.7220</td><td>0.6834</td></tr><tr><td>Grade3</td><td>Grade1</td><td>0.7108</td><td>0.7560</td><td>0.7108</td><td>0.6884</td></tr><tr><td>Grade3</td><td>Grade2</td><td>0.9148</td><td>0.9307</td><td>0.9148</td><td>0.9163</td></tr><tr><td colspan="2">Mean (Swin-ResNet KL)</td><td></td><td>0.7242 ± 0.1139</td><td></td><td></td><td>0.6771 ± 0.1576</td></tr><tr><td rowspan="6">Swin-ResNet (Dual CE)</td><td>Grade1</td><td>Grade2</td><td>0.5981</td><td>0.5084</td><td>0.5981</td><td>0.5238</td></tr><tr><td>Grade1</td><td>Grade3</td><td>0.7804</td><td>0.7857</td><td>0.7804</td><td>0.7826</td></tr><tr><td>Grade2</td><td>Grade1</td><td>0.6066</td><td>0.4124</td><td>0.6066</td><td>0.4894</td></tr><tr><td>Grade2</td><td>Grade3</td><td>0.7540</td><td>0.8089</td><td>0.7540</td><td>0.7128</td></tr><tr><td>Grade3</td><td>Grade1</td><td>0.6826</td><td>0.7128</td><td>0.6826</td><td>0.6508</td></tr><tr><td>Grade3</td><td>Grade2</td><td>0.8904</td><td>0.9104</td><td>0.8904</td><td>0.8918</td></tr><tr><td colspan="2">Mean (Swin-ResNet Dual CE)</td><td></td><td>0.7187 ± 0.1122</td><td>一</td><td></td><td>0.6752 ± 0.1536</td></tr></table>

Several observations emerge from this analysis. First, the T1G setting reveals a clear asymmetry in cross-grade transferability: models trained on Grade 3 (premium quality) generalize significantly better to unseen grades, particularly achieving the highest single-run accuracy of 0.9148 when evaluated on Grade 2. In contrast, training on Grade 1 (heavily blemished) or Grade 2 results in lower transfer accuracy, especially when tested on Grade 1 ? the most visually challenging domain. This is consistent with the intuition that high-quality training data captures clean, discriminative variety features, whereas degraded-quality images introduce noise that limits feature transferability.

Second, the Swin-ResNet (KL) model achieves a mean accuracy of 0.7242 across all six T1G transfer settings, compared to 0.7187 for the Dual CE variant, confirming that KL-divergence-based inter-stream distillation provides a consistent, albeit modest, benefit under single-source domain conditions. The corresponding F1-score improvement (0.6771 vs. 0.6752) indicates marginally more balanced class-wise predictions. Notably, both variants share the same dual-stream architecture, isolating the contribution of distributional alignment. Compared to both LOGO results, the mean accuracy under the T1G protocol is lower overall, reflecting the greater dificulty of the single-source transfer setting and the larger distribution shift between the training and test domains.

Third, all models exhibit high final training accuracy (best validation accuracy ≈ 1.000) alongside competitive test performance, suggesting that the dual-stream architecture learns highly concentrated within-grade representations. The trainingto-test generalization gap observed in the T1G protocol highlights the importance of exposure to diverse grade conditions during training, which the LOGO protocol explicitly provides. Overall, these results indicate that the proposed hybrid framework maintains robust generalization even in extreme single-source domain settings, and that KL-divergence regularization continues to provide consistent benefits across both the LOGO and T1G evaluation protocols.

## 6.4 Ablation Study

Table 7 presents a comprehensive ablation analysis. It highlights the individual and combined contributions of Dual CE supervision, feature alignment via the adaptor, and KL-divergence-based distillation.

Table 7: Ablation Study: Grade-wise and Component-wise Performance Analysis
<table><tr><td>Ablation Study</td><td>G1 Acc.</td><td>G2 Acc.</td><td>G3 Acc.</td><td>Mean Acc. ± Std</td><td>Mean F1</td><td>Best Acc.</td><td>Worst Acc.</td></tr><tr><td colspan="8">Reference Baselines (Independent Training)</td></tr><tr><td>Swin-Tiny (Teacher only)</td><td>0.6654</td><td>0.7980</td><td>0.7249</td><td>0.7294 ± 0.0664</td><td>0.7118</td><td>0.7980</td><td>0.6654</td></tr><tr><td>ResNet50 (Student only)</td><td>0.6465</td><td>0.6609</td><td>0.7760</td><td>0.6945 ± 0.0710</td><td>0.6597</td><td>0.7760</td><td>0.6465</td></tr><tr><td colspan="8">Ablation Variants (Isolating Components)</td></tr><tr><td>w/o Adaptor (Dual CE)</td><td>0.6370</td><td>0.8111</td><td>0.8719</td><td>0.7733 ± 0.1219</td><td>0.7577</td><td>0.8719</td><td>0.6370</td></tr><tr><td>Adaptor only (Single CE)</td><td>0.6274</td><td>0.7507</td><td>0.8621</td><td>0.7467 ± 0.1174</td><td>0.7222</td><td>0.8621</td><td>0.6274</td></tr><tr><td>Adaptor + Dual CE</td><td>0.6687</td><td>0.8700</td><td>0.9369</td><td>0.8252 ± 0.1396</td><td>0.8085</td><td>0.9369</td><td>0.6687</td></tr><tr><td>Adaptor + KL only (w/o CE)</td><td>0.2472</td><td>0.1282</td><td>0.3750</td><td>0.2501 ± 0.1235</td><td>0.1810</td><td>0.3750</td><td>0.1282</td></tr><tr><td>Adaptor + Single CE + KL</td><td>0.6292</td><td>0.7988</td><td>0.9129</td><td>0.7803 ± 0.1428</td><td>0.7497</td><td>0.9129</td><td>0.6292</td></tr><tr><td colspan="8">Proposed Full Framework</td></tr><tr><td>Swin-ResNet (Full KL)</td><td>0.7386</td><td>0.7781</td><td>0.9209</td><td>0.8125 ± 0.0946</td><td>0.8035</td><td>0.9209</td><td>0.7386</td></tr></table>

## Architectural and Objective Definitions:

• Dual Cross-Entropy (Dual CE): Independent supervision is applied to both branches by enforcing classification loss on the teacher (Swin Transformer) and student (ResNet50) logits: $\mathcal { L } _ { C E } ( z _ { T } , y ) + \mathcal { L } _ { C E } ( z _ { S } , y )$ This setting encourages each branch to learn discriminative representations individually..

• Single Cross-Entropy (Single CE): upervision is applied only after feature fusion, i.e., on the final fused logits. This evaluates whether joint optimization alone is suficient without explicitly guiding individual branches.

• KL-Divergence Distillation: A distillation loss is introduced to align the output distributions of the student with the teacher, promoting knowledge transfer across branches. Note that “w/o Adaptor” variants cannot utilize KL distillation due to the dimension mismatch between Student $( d _ { S } )$ and Teacher $( d _ { T } )$ feature spaces.

• Full Model: The complete architecture integrates the Adaptor module, Dual CE supervision, and KL-divergence distillation. This configuration enables both independent learning and cross-branch knowledge transfer, thereby improving robustness across varying quality grades.

## 6.5 Confusion Matrix Analysis

Figure 2 illustrates the confusion matrices for the best-performing model, the Swin-ResNet Hybrid with KL Divergence. The confusion matrices of the proposed

![](images/ef31952d093686422efff922204d477d6ec8c4ffe37f4a3cce9570f5c25790bc.jpg)  
(a) Grade 1 Test

![](images/0327bc85a013e428dcb1a644a6ff71c8318bd9c40216bef59391bbf693064e7e.jpg)  
(b) Grade 2 Test

![](images/3d160038b1869e375d12fba2778fe6fe081a3435c29a2eacbd194bdec973f25b.jpg)  
(c) Grade 3 Test  
Fig. 2: Confusion Matrices for Swin-ResNet (KL) across all test grades. The strong diagonal even in Grade 1 demonstrates superior feature robustness compared to baseline CNNs.

Swin?ResNet (KL Hybrid) model across Grade 1 and Grade 3 demonstrate strong diagonal dominance, indicating efective class discrimination and stable cross-grade generalisation. In Grade 1, while overall classification performance remains satisfactory, relatively higher inter-class confusion is observed, particularly between Elakki-bale and Rasbale. The Rasbale class exhibits comparatively greater misclassification, suggesting higher intra-class variability at this grade level. In Grade 2, the model achieves the best performance, with near-perfect classification for Elakki-bale and minimal of-diagonal entries across all classes. This reflects enhanced class separability and well-structured feature representations. For Grade 3, high classification accuracy is maintained with limited inter-class confusion. Although minor misclassification persists for Rasbale, overall separability remains strong and superior to Grade 1. Overall, the results confirm that the proposed KL-regularized hybrid framework learns discriminative and grade-consistent feature representations, with Grade 2 demonstrating the highest separability and Rasbale remaining the most challenging class across grades.

## 6.6 Training Dynamics

The training stability of the Swin-ResNet Hybrid (KL Divergence) architecture was rigorously analyzed across all three Leave-One-Grade-Out (LOGO) cross-validation folds. Figure 3 presents a comprehensive 3×2 matrix of the training dynamics. The Left Column displays the standard Loss Convergence (Training vs. Validation), illustrating how the model minimizes error over epochs. The consistently small gap between training and validation loss reflects good generalization, minimal overfitting, and stable convergence behavior. Overall, the model demonstrates smooth and well-controlled optimization without signs of divergence or instability. The Right Column presents the Rate of Loss Change $\left( \Delta L = L _ { t } - L _ { t - 1 } \right)$ , which serves as a proxy for optimization stability. The sharp negative drop in early epochs reflects strong gradient-driven updates, whereas near-zero fluctuations in later epochs confirm stabilization and fine-tuning near a local minimum.

## 6.7 Training Eficiency Analysis

Table 8 shows epochs to early stopping. The fewer epochs signify faster convergence. The baselines that need more training are ResNet50 (25?19?12 epochs), EficientNet-B1 (19?18?17 epochs), and Swin-Tiny (21?24?16 epochs). The standard Swin-ResNet reduces epochs but stays slower on Grade 2. The hybrid models show clear eficiency gains. The best performing hybrids are KL-based ones, i.e., Swin-EficientNet (KL) maintains its eficiency over time, and Swin-ResNet (KL) converges the quickest (8?8?10 epochs). All in all, KL-divergence alignment speeds up optimization and makes it possible for the suggested hybrids to train more quickly than independent and non-distilled models.

Table 8: Training Epochs Until Early Stopping
<table><tr><td>Model</td><td>Grade1 Test</td><td>Grade2 Test</td><td>Grade3 Test</td></tr><tr><td>ResNet50</td><td>25</td><td>19</td><td>12</td></tr><tr><td>EfficientNet-B1</td><td>19</td><td>18</td><td>17</td></tr><tr><td>Swin-Tiny</td><td>21</td><td>24</td><td>16</td></tr><tr><td>Swin-ResNet(Standard)</td><td>10</td><td>24</td><td>9</td></tr><tr><td>Swin-ResNet(KL)</td><td>8</td><td>8</td><td>10</td></tr><tr><td>Swin-EfficientNet(KL)</td><td>9</td><td>12</td><td>16</td></tr></table>

![](images/e5dfc1f7c9c4053ed1df120fdef277160db22b4937414fdbb768fd46eb4c71aa.jpg)  
(a) Loss Convergence (Test: Grade 1)

![](images/1eb1e8a758cb6aff76eb99420b78d533e238916ec6a6df1c2959b458c1669b91.jpg)  
(b) Rate of Change (Test: Grade 1)

![](images/c0798955d598156577a5f383ca12ff2700db349f13229d4506cab14d8480d09c.jpg)  
(c) Loss Convergence (Test: Grade 2)

![](images/fc16e0c61b63719e2c89f74555c771236ace207071840706490135fc88d3d9dc.jpg)  
(d) Rate of Change (Test: Grade 2)

![](images/dd5b130f3c661ade8fc75a430c991aace173f99c4b73dd41268d5e1055eaf83f.jpg)

![](images/df145e46fb6676f17f672199013f09218e4c2d08873622c5898f42bf1dddfb4f.jpg)  
(e) Loss Convergence (Test: Grade 3)  
(f) Rate of Change (Test: Grade 3)

Fig. 3: Training Dynamics Matrix. The left column shows the cross-entropy loss profiles, where the close alignment of training (blue) and validation (red) curves indicates minimal overfitting. The right column illustrates the rate of loss change, where the rapid settling near zero $( \Delta L \approx 0 )$ confirms stable convergence without significant oscillations, even in the challenging Grade 1 scenario.

## 7 Qualitative Analysis: Success vs. Failure Modes

To better understand the model’s behavior, we conducted a side-by-side analysis of successful predictions versus misclassifications across all quality grades. We specifically examine the alignment between the Student (ResNet) and Teacher (Swin) attention maps using the visualization grids generated during testing.

## 7.1 Grade 1 Analysis (Hardest Domain)

Grade 1 represents the most challenging domain due to high variability.

![](images/b0183c20940c48791eec204f38ebf877f6a6a57577bc8db5d62d1453a79f7cb9.jpg)  
(a) Correct Prediction (Rasbale): Strong agreement between Student and Teacher attention maps (Grad-CAM IoU: 0.268) on the fruit structure.

![](images/f483a8d14b3c6269aaded09c0d3b5240de46ada57c14d484bcdf8f35bdaffa4a.jpg)  
(b) Incorrect Prediction (Pachbale → Pred: Elakki): Despite moderate attention overlap, the model confuses Pachbale with Elakki-bale, a common error in Grade1 due to similar texture profiles.  
Fig. 4: Grade 1 Success vs. Failure Case Study.

## 7.1.1 Grade 2 Analysis (Medium Quality)

## 7.1.2 Grade 3 Analysis (Easiest Domain)

Grade 3 typically shows the highest accuracy, but misclassifications still occur when visual features are ambiguous.

## 7.2 Interpretability Analysis: Student vs. Teacher Attention

To qualitatively assess the decision-making behavior of the proposed hybrid architecture, we employed Gradient-weighted Class Activation Mapping (Grad-CAM) and Score-CAM to visualize class-discriminative regions. The analysis focuses on the Student branch (ResNet50) within the hybrid framework to examine how knowledge transferred from the Teacher (Swin Transformer) influences spatial attention patterns. For all visualizations, feature activations were extracted from the final convolutional block of the ResNet50 backbone (layer4[-1]), as this layer captures high-level semantic representations while preserving spatial localization. Figure 7 presents a comparative visualization between the Student branch in the hybrid model and the baseline Swin Transformer.

![](images/b0f00297ac1feb3998ad673dcceb88bbd06e17675ab8bea72abb66d5e5f48cad.jpg)  
(a) Correct Classification (Pachbale): Accurate localization of the fruit bunch, with the Student model efectively aligning with the Teacher?s attention and capturing key discriminative features.

![](images/027f994635ca4f60b78e5cac60a00d2d651cb5cbe6f096cae7dfa4699fb82918.jpg)  
(b) Misclassification (Rasbale → Elakki-bale): Despite focusing on the relevant region (IoU = 0.176), the model fails to distinguish fine-grained visual characteristics, leading to an incorrect prediction.  
Fig. 6: Qualitative comparison of correct and incorrect predictions for Grade 3 samples, illustrating the model?s localization capability and challenges in fine-grained discrimination.

Each sample is arranged in a three-row stacked format: the first row presents the original input image, the second row shows the Grad-CAM/Score-CAM attention map of the Student (ResNet50) within the hybrid architecture, and the third row displays the attention map of the baseline Swin Transformer (Teacher reference). The side-byside comparison enables interpretability-driven evaluation of spatial focus consistency. Notably, the hybrid Student demonstrates enhanced localization of defect-specific regions (e.g., bruises, fungal lesions, and discoloration zones) with reduced background activation, indicating improved feature refinement through knowledge alignment.

Table 9: Teacher-Student Attention Alignment (IoU Scores) for Correct Predictions
<table><tr><td>Grade</td><td>True Class</td><td>Sample ID</td><td>Grad-CAM IoU</td><td>Score-CAM IoU</td></tr><tr><td>Grade 1</td><td>Rasbale</td><td>9480</td><td>0.268</td><td>0.114</td></tr><tr><td>Grade 1</td><td>Elakki-bale</td><td>1623</td><td>0.313</td><td>0.202</td></tr><tr><td>Grade 2</td><td>Rasbale</td><td>10169</td><td>0.362</td><td>0.221</td></tr><tr><td>Grade 2</td><td>Elakki-bale</td><td>1905</td><td>0.375</td><td>0.017</td></tr><tr><td>Grade 3</td><td>Elakki-bale</td><td>2972</td><td>0.307</td><td>0.217</td></tr><tr><td>Grade 3</td><td>Rasbale</td><td>9392</td><td>0.176</td><td>0.337</td></tr></table>

Grade 1 (Sample 1) Grade 2 (Sample 3) Grade 3 (Sample 4)  
![](images/679c3708a7f2d91fad88fd2079a7cf52b19c9c4abdd4431d03b728f6de184c35.jpg)  
Row 1: Grad-CAM Comparison (Target: ResNet50 Layer4)  
Fig. 7: Student vs. Teacher Attention Matrix. A 2×3 comparison across all quality grades. In each stacked image, the middle strip represents the Student’s (ResNet50) attention. The strong overlap between the Student’s focus and the relevant fruit regions indicates efective feature learning from the Teacher, even though the target layer is strictly from the ResNet50 backbone.

## 7.2.1 Quantitative Analysis: IoU Scores

Table 9 presents the quantitative Intersection over Union (IoU) scores between Grad-CAM and Score-CAM attention maps, measuring the spatial overlap of the generated activation masks. The IoU metric provides an objective assessment of attention consistency, where higher values indicate stronger agreement in the discriminative regions highlighted by both methods within the hybrid framework. Results show that the alignment between the two approaches is moderate and inconsistent. In general, Grad-CAM produces higher IoU values than Score-CAM, indicating more stable spatial localization (e.g., 0.362 vs. 0.221 for Grade 2 Rasbale and 0.375 vs. 0.017 for Grade 2 Elakki-bale). Score-CAM is more sensitive to perturbation-based attribution, as evidenced by its greater variability, which occasionally includes very little overlap. There are some exceptions, though; in Grade 3 Rasbale, Score-CAM is higher than Grad-CAM (0.337 vs. 0.176), suggesting that it can occasionally better align with class-relevant regions. Overall, the findings support the complementary nature of the two approaches in capturing distinct facets of model attention, as they show partial but inconsistent agreement.

## 8 Conclusion

Robust automated fruit classification frameworks must obtain reliable performance under diferent quality and post-harvest handling conditions. This study addressed the challenging issue of cross grades banana variety classification such that the frameworks are trained on specific quality grades and tested on unseen grades. Using a large-scale database with three commercial quality grades and three varieties, we comprehensively compared CNN, Vision Transformer, and hybrid architectures using a strict Leave-One-Grade-Out (LOGO) evaluation protocol. We presented a dual-stream Swin?ResNet hybrid system augmented with KL-divergence based self-distillation in order to overcome single-paradigm models? limitations. The presented hybrid approach learns more robust and grade-invariant representations by explicitly aligning predictive distributions and by using global context and local texture cues. According to experimental results, the hybrid framework achieved the best overall performance and the fastest convergence over baseline models. The enhanced stability and discriminative power are further validated by grade-wise analysis and attention visualizations under dificult low-quality conditions. In spite of these encouraging outcomes, a number of areas still remains for future work such as if using domain generalization and data augmentation schemes could improve robustness even more in extreme visual variability, investigating lightweight hybrid variants might allow for real-time deployment in agricultural settings with limited resources, and applying the framework to multiple fruits or regions datasets would aid in evaluating its wider generalization potential. All in all, this study shows that distillation guided CNN-Transformer hybridization is an eficient and intelligent approach for cross-grade agricultural image classification and inspection systems.

## 9 Statement and Declarations

This work is original and has been carried out independently by the authors. All sources of information used in this study have been properly acknowledged. The results presented in this manuscript have not been submitted to or published in any other journal or conference. The authors declare that no funding was received for this work. They have no conflicts of interest to disclose. This article does not involve any studies with human participants or animals conducted by the authors.

## 10 Funding

This research received no specific grant from any funding agency in the public, commercial, or not-for-profit sectors.

## 11 Acknowledgements

The authors thank the Department of Artificial Intelligence and the Department of Computer Science, SVNIT Surat, for computational resources on the dual NVIDIA H100 NVL GPU cluster.

## 12 Author Contributions

Praveen Kumar Chandaliya and Khush Kataruka contributed to the conceptualization of study. Methodology was developed by Raghavendra Ramachandra, Khush Kataruka, and Praveen Kumar Chandaliya. Formal analysis was carried out by Mohammad Muzammil and Praveen Kumar Chandaliya, while investigation was performed by Zahid Akhtar and Praveen Kumar Chandaliya. Resources were provided by Praveen Kumar Chandaliya and Raghavendra Ramachandra. Data curation was conducted by Khush Kataruka and Mohammad Muzammil. Praveen Kumar Chandaliya and Zahid Akhtar prepared the original draft of the manuscript, and Mohammad Muzammil contributed to visualization. Supervision was provided by Praveen Kumar Chandaliya and Zahid Akhtar. All authors have read and agreed to the published version of the manuscript.

## 13 Competing interests

The authors declare that they have no competing interests.

## 14 Availability of data and material

The dataset used in this study is publicly available through Mendeley Data and can be accessed directly at: https://data.mendeley.com/datasets/dpjpdzdmsw/2 Users can download the complete dataset from the above repository. The dataset is systematically organized into folders according to banana variety, grade, and imaging scale. All images and videos are properly labeled to facilitate reproducibility and further research.

## References

, 2026. Uav-prior-guided ugv path planning in ground-constrained orchards: a case study in banana plantations. Computers and Electronics in Agriculture 248, 111778. URL: https://www.sciencedirect.com/science/article/pii/ S016816992600373X, doi:https://doi.org/10.1016/j.compag.2026.111778.

Al-Dairi, M., Pathare, P.B., Al-Yahyai, R., Jayasuriya, H., Al-Attabi, Z., 2023. Postharvest quality, technologies, and strategies to reduce losses along the supply chain of banana: A review. Trends in Food Science and Technology 134, 177–191. doi:https://doi.org/10.1016/j.tifs.2023.03.003.

Al Haque, A.F., Hakim, M.A., Hafiz, R., 2021. Cnn based automatic computer vision system for strain detection and quality identification of banana, in: 2021 International Conference on Automation, Control and Mechatronics for Industry 4.0 (ACMI), IEEE. pp. 1–6.

Arakeri, M., Lakshmana, 2016. Computer vision based fruit grading system for quality evaluation of tomato in agriculture industry. Procedia Computer Science 79, 426– 433. URL: https://www.sciencedirect.com/science/article/pii/S1877050916001861, doi:https://doi.org/10.1016/j.procs.2016.03.055. proceedings of International Conference on Communication, Computing and Virtualization (ICCCV) 2016.

Chen, X., Xun, Y., Li, W., Zhang, J., 2010. Combining discriminant analysis and neural networks for corn variety identification. Computers and Electronics in Agriculture 71, S48–S53. URL: https://www.sciencedirect.com/science/article/pii/ S0168169909001811, doi:https://doi.org/10.1016/j.compag.2009.09.003. special issue on computer and computing technologies in agriculture.

Dinata, M.I., Nugroho, S.M.S., Rachmadi, R.F., 2021. Classification of strawberry plant diseases with leaf image using cnn, in: 2021 International Conference on Artificial Intelligence and Computer Science Technology (ICAICST), IEEE. pp. 68–72.

Dittakan, K., Theera-Ampornpunt, N., Witthayarat, W., Hinnoy, S., Klaiwan, S., Pratheep, T., 2017. Banana cultivar classification using scale invariant shape analysis, in: 2017 2nd International Conference on Information Technology (INCIT), pp. 1–6. doi:10.1109/INCIT.2017.8257854.

Fernando, I., Fei, J., Stanley, R., Enshaei, H., Eyles, A., 2019. Quality deterioration of bananas in the post-harvest supply chain-an empirical study. Modern Supply Chain Research and Applications 1, 135–154.

Fu, L., Duan, J., Zou, X., Lin, G., Song, S., Ji, B., Yang, Z., 2019. Banana detection based on color and texture features in the natural environment. Computers and Electronics in Agriculture 167, 105057. URL: https:// www.sciencedirect.com/science/article/pii/S0168169919313742, doi:https://doi. org/10.1016/j.compag.2019.105057.

Ghazal, S., Qureshi, W.S., Khan, U.S., Iqbal, J., Rashid, N., Tiwana, M.I., 2021. Analysis of visual features and classifiers for fruit classification problem. Computers and Electronics in Agriculture 187, 106267. URL: https:// www.sciencedirect.com/science/article/pii/S0168169921002842, doi:https://doi.

org/10.1016/j.compag.2021.106267.

Gurjar, B., Torres, U., Coleman, G., Straw, C., Bagavathiannan, M., 2026. Efect of mowing, imaging technique, and annotation method on weed detection in turfgrass using yolo. Precision Agrictural 27, 46.

Guru, D., N, S., 2025. Banana bunch image and video dataset for variety classification and grading. Data in Brief 60, 111478. URL: https:// www.sciencedirect.com/science/article/pii/S2352340925002100, doi:https://doi. org/10.1016/j.dib.2025.111478.

He, K., Zhang, X., Ren, S., Sun, J., 2016. Deep residual learning for image recognition, in: Proceedings of the IEEE Conference on Computer Vision and Pattern Recognition (CVPR), pp. 770–778.

Kambo, R., Yerpude, A., 2014. Classification of basmati rice grain variety using image processing and principal component analysis. arXiv preprint arXiv:1405.7626 .

Khan, A., Rauf, Z., Sohail, A., Khan, A.R., Asif, H., Asif, A., Farooq, U., 2023. A survey of the vision transformers and their cnn-transformer based variants. Artificial Intelligence Review 56, 2917–2970.

Li, Z., Chen, G., Zhang, T., 2020. A cnn-transformer hybrid approach for crop classification using multitemporal multisensor images. IEEE Journal of Selected Topics in Applied Earth Observations and Remote Sensing 13, 847–858.

Li, Z., Liu, F., Yang, W., Peng, S., Zhou, J., 2021. A survey of convolutional neural networks: analysis, applications, and prospects. IEEE transactions on neural networks and learning systems 33, 6999–7019.

Liakos, K.G., Busato, P., Moshou, D., Pearson, S., Bochtis, D., 2018. Machine learning in agriculture: A review. Sensors 18, 2674.

Liu, Z., Lin, Y., Cao, Y., Hu, H., Wei, Y., Zhang, Z., Lin, S., Guo, B., 2021. Swin transformer: Hierarchical vision transformer using shifted windows, in: Proceedings of the IEEE/CVF International Conference on Computer Vision (ICCV), pp. 10012– 10022.

Mehdipour, S., Mirroshandel, S.A., Tabatabaei, S.A., 2025. Vision transformers in precision agriculture: A comprehensive survey. arXiv preprint arXiv:2504.21706 .

Mehdipour, S., Mirroshandel, S.A., Tabatabaei, S.A., 2026. Vision transformers in precision agriculture: A comprehensive survey. Intelligent Systems with Applications 29, 200617. URL: https://www.sciencedirect.com/science/article/pii/ S2667305325001437, doi:https://doi.org/10.1016/j.iswa.2025.200617.

Moslemi, A., Briskina, A., Dang, Z., Li, J., 2024. A survey on knowledge distillation: Recent advancements. Machine Learning with Applications 18, 100605.

Olisah, C.C., Trewhella, B., Li, B., Smith, M.L., Winstone, B., Whitfield, E.C., Fern´andez, F.F., Duncalfe, H., 2024. Convolutional neural network ensemble learning for hyperspectral imaging-based blackberry fruit ripeness detection in uncontrolled farm environment. Engineering applications of artificial intelligence 132, 107945.

Ponce, J.M., Aquino, A., Andujar, J.M., 2019. Olive-fruit variety classification by means of image processing and convolutional neural networks. IEEE Access 7, 147629–147641.

Santos Pereira, L.F., Barbon, S., Valous, N.A., Barbin, D.F., 2018. Predicting the ripening of papaya fruit with digital imaging and random forests. Computers and Electronics in Agriculture 145, 76–82. URL: https://www. sciencedirect.com/science/article/pii/S016816991731030X, doi:https://doi.org/ 10.1016/j.compag.2017.12.029.

Sarigu, M., Grillo, O., Lo Bianco, M., Ucchesu, M., d’Hallewin, G., Loi, M.C., Venora, G., Bacchetta, G., 2017. Phenotypic identification of plum varieties (prunus domestica l.) by endocarps morpho-colorimetric and textural descriptors. Computers and Electronics in Agriculture 136, 25–30. URL: https:// www.sciencedirect.com/science/article/pii/S0168169916308523, doi:https://doi. org/10.1016/j.compag.2017.02.009.

Sarode, K.R., Patil, S.S., 2026. Pyramidal convolution rex-net with coordinate bobcat attention networks based anomaly detection and classification for banana leaf diseases. Computers and Electronics in Agriculture 247, 111669. URL: https:// www.sciencedirect.com/science/article/pii/S0168169926002644, doi:https://doi. org/10.1016/j.compag.2026.111669.

Sharma, S.K., Vishwakarma, D.K., 2024. Classification of banana plant leaves based on nutrient deficiency using vision transformer, in: 2024 5th International Conference for Emerging Technology (INCET), pp. 1–6. doi:10.1109/INCET61516.2024. 10593120.

Sheikh, M.R., Islam, M.M., Himel, G.M.S., 2025. Enhancing precision in banana variety classification using deep learning model. Data Science and Informetrics 5, 18–32. doi:https://doi.org/10.1016/j.dsim.2025.05.002.

Shuprajhaa, T., Mathav Raj, J., Paramasivam, S.K., Sheeba, K., Uma, S., 2023. Deep learning based intelligent identification system for ripening stages of banana. Postharvest Biology and Technology 203, 112410. URL: https:// www.sciencedirect.com/science/article/pii/S0925521423001710, doi:https://doi. org/10.1016/j.postharvbio.2023.112410.

Su, W., Yang, Y., Zhou, C., Zhuang, Z., Liu, Y., 2023. Multiple defect classification method for green plum surfaces based on vision transformer. Forests 14, 1323.

Tan, M., Le, Q.V., 2019. Eficientnet: Rethinking model scaling for convolutional neural networks, in: Proceedings of the International Conference on Machine Learning (ICML), pp. 6105–6114.

Tiwari, R.G., Misra, A., Maheshwari, H., Agarwal, A.K., Sharma, M., 2024. Hybrid transformer-cnn model for automated diagnosis of pomegranate fruit diseases, in: 2024 10th International Conference on Electrical Energy Systems (ICEES), pp. 1–5. doi:10.1109/ICEES61253.2024.10776810.

Too, E.C., Yujian, L., Njuki, S., Yingchun, L., 2019. A comparative study of fine-tuning deep learning models for plant disease identification. Computers and Electronics in Agriculture 161, 272–279. URL: https://www.sciencedirect.com/science/article/ pii/S0168169917313303, doi:https://doi.org/10.1016/j.compag.2018.03.032. bigData and DSS in Agriculture.

Wallelign, S., Polceanu, M., Buche, C., 2018. Soybean plant disease identification using convolutional neural network., in: FLAIRS, pp. 146–151.

Wang, J., Wang, W., Liao, L., Luo, L., Lin, X., Zeng, X., 2025. An approach based on knowledge distillation for lightweight defect classification of green plums. IEEE Transactions on AgriFood Electronics 3, 213–223. doi:10.1109/TAFE.2024. 3488196.

Yasin, M., Gangan, S., Panchal, S.K., 2025. Banana peels: A genuine waste or a wonderful opportunity? Applied Sciences 15. URL: https://www.mdpi.com/2076-3417/ 15/6/3195, doi:10.3390/app15063195.

Zangana, H.M., Mohammed, A.K., Mustafa, F.M., 2024. Advancements and applications of convolutional neural networks in image analysis: A comprehensive review. Jurnal Ilmiah Computer Science 3, 16–29.

Zhang, K., Kang, F., Wang, N., Cao, Y., Yang, L., Wang, Y., Chen, C., 2026. Prediction of pesticide deposition in fruit tree canopies: A voxel-based analysis approach. Precision Agrictural 27, 43.

Zhang, Y., Yang, X., Cheng, Y., et. al, 2024. Fruit freshness detection based on multitask convolutional neural network. Current Research in Food Science 8, 100733. doi:https://doi.org/10.1016/j.crfs.2024.100733.

Zhuang, J., Hou, C., Tang, Y., He, Y., Guo, Q., Miao, A., Zhong, Z., Luo, S., 2019. Assessment of external properties for identifying banana fruit maturity stages using optical imaging techniques. Sensors 19. URL: https://www.mdpi.com/1424-8220/ 19/13/2910, doi:10.3390/s19132910.