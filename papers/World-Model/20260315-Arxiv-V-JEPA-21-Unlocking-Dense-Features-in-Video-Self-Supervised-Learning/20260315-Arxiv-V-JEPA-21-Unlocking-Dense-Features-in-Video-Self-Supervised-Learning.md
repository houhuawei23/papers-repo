# Title: V-JEPA 2.1: Unlocking Dense Features in Video Self-Supervised Learning

- ArXiv: 2603.14482
- Authors: Lorenzo Mur-Labadia, Matthew Muckley, Amir Bar, Mido Assran, Koustuv Sinha, Mike Rabbat, Yann LeCun, Nicolas Ballas, Adrien Bardes, [
- Sections: 80
- Estimated tokens: 74.4k

## Contents

- 1 Introduction
- 2 Methodology
  - 2.1 Preliminaries: Joint-Embedding Predictive Architectures
  - 2.2 Analysis of V-JEPA Features for Dense Vision Tasks
    - Observations and Hypothesis.
    - Context Self-Supervision.
  - 2.3 V-JEPA 2.1: Improving Dense Video SSL Features
    - VJEPA 2.1 Architecture.
    - Implementation Details.
    - Empirical Evaluation.
    - 2.3.1 Dense Prediction Loss
    - 2.3.2 Deep Self-Supervision
    - 2.3.3 Scaling Image Data.
    - 2.3.4 Multi-Modal Tokenizer
    - 2.3.5 Scaling Model Size to ViT-G (2B) and High-Resolution Cool-Down
    - 2.3.6 Model Distillation
- 3 Results
  - 3.1 Short-Term Object Interaction Anticipation
    - Task.
    - Evaluation protocol.
    - Results.
  - 3.2 Action Anticipation
    - Task.
    - Evaluation protocol.
    - Results.
  - 3.3 Robotic Arm Planning
  - 3.4 Navigation Planning
  - 3.5 Depth Estimation and Semantic Segmentation
    - Task.
    - Evaluation protocol.
    - Results.
  - 3.6 Video Object Segmentation
    - Task.
    - Evaluation protocol.
    - Results.
  - 3.7 Video and Image Classification
    - Task.
    - Evaluation protocol.
    - Results.
  - 3.8 Video Question Answering
    - Task.
    - Evaluation protocol.
    - Results.
  - 3.9 Qualitative results of V-JEPA 2.1 Dense Features
  - 3.10 Family of distilled models
- 4 Related work
  - Self-Supervised Learning.
  - Video Models.
  - Learning dense features.
- 5 Conclusion and Future work
  - Future work.
- References
- 6 Pretraining details
- 7 Distillation details
- 8 Evaluation protocols
  - 8.1 Depth Estimation
    - Datasets and Metrics.
    - Evaluation Protocol.
  - 8.2 Semantic Segmentation
    - Datasets and Metrics.
    - Evaluation Protocol.
  - 8.3 Video Object Segmentation Tracking
    - Dataset and Metrics.
    - Evaluation Protocol.
  - 8.4 Short Term Object Interaction Anticipation
    - Dataset and Metrics.
    - Evaluation Protocol.
    - Probe Architecture.
    - Optimization.
  - 8.5 Video and Image Classification
    - Dataset and Metrics.
    - Probe Architecture.
    - Evaluation Protocol.
    - Optimization.
  - 8.6 Action Anticipation
    - Dataset and Metrics.
    - Evaluation Protocol.
- 9 Additional Ablations
  - 9.1 Multi-scale evaluation
  - 9.2 Pretraining Spatial Resolution

## Abstract

###### Abstract

We present V-JEPA 2.1, a family of self-supervised models that learns _dense_, high-quality representations for visual scenes in both images and videos, while retaining strong _global_ scene understanding. V-JEPA 2.1 combines four key ingredients: (i) a Dense Predictive Loss, a masking-based objective in which _all_ tokens—visible context and masked tokens alike—contribute to the training loss, encouraging explicit spatial and temporal grounding; (ii) Deep Self-Supervision, which applies the self-supervised objective hierarchically at multiple intermediate encoder layers to improve representation quality ; (iii) Multi-Modal Tokenizers that support unified training over images and videos; and (iv) effective model and data scaling. These design choices substantially improve dense feature quality, yielding representations that are spatially structured, semantically coherent, and temporally consistent.
. Empirically, V-JEPA 2.1 achieves state-of-the-art results on a range of benchmarks: 7.71 mAP on Ego4D for short-term object-interaction anticipation, 40.8 Recall@5 on EPIC-KITCHENS for high-level action anticipation, and a 20% improvement in real-robot grasping success rate over VJEPA-2 AC. The model also demonstrates state-of-art performances in robotic navigation (5.687 ATE on Tartan Drive), depth estimation (0.307 RMSE on NYUv2 with a linear probe), and global recognition (77.7% on Something-Something-V2).
Our results demonstrate that V-JEPA 2.1 advances the state of the art in dense visual understanding and world modeling.

, \metadata[Code][https://github.com/facebookresearch/vjepa2](https://github.com/facebookresearch/vjepa2)

<a id="figure-1"></a>

![teaser_screenshot_5dice_onlyimg_OLD](images/teaser_screenshot_5dice_onlyimg_OLD.png)

> Figure 1: V-JEPA 2.1 unlocks high-quality dense features. We compute PCA on patch features extracted from the same image or video and map the top three components to RGB channels for both V-JEPA 2 (ViT-g) and V-JEPA 2.1 (ViT-G). Our novel V-JEPA 2.1 produces dense representations with strong spatial and temporal consistency, learning semantically coherent features where similar objects map to the same PCA components.

<a id="section-1"></a>

## 1 Introduction

World models hold the promise of enabling agents to perceive, predict, and plan effectively in the physical world (Sutton, 1981; Ha and Schmidhuber, 2018; Assran et al., 2023). At the core of these models lies the state-estimation problem: learning representations that reliably summarize the current world state from low-level, noisy perceptual inputs. Self-Supervised Learning (SSL) from video has recently emerged as a powerful route to this goal (Caron et al., 2021; Assran et al., 2025), because it can exploit large-scale, label-free data to learn representations that capture scene geometry, dynamics, and intrinsic physical properties (Siméoni et al., 2025; Garrido et al., 2025).

<a id="figure-2"></a>

![bars_teaser_tikz](images/bars_teaser_tikz.png)

> Figure 2: V-JEPA 2.1 ViT-G performance across dense and global prediction tasks. We show the relative improvements of V-JEPA 2.1 compared to the previous V-JEPA 2 ViT-g model (Assran et al., 2025). We also report the performance of previous SOTA models using a frozen backbone evaluation: DINOv3 (Siméoni et al., 2025) is the reference model for depth estimation, object tracking, semantic segmentation, SSv2 action recognition, and image classification; InternVideo2s (Wang et al., 2024b) for K400 action recognition, STAformer (Mur-Labadia et al., 2024) for short-term object interaction anticipation, and PlausiVL (Mittal et al., 2024) for action anticipation. Tasks where V-JEPA 2.1 ViT-G obtains SOTA in frozen-backbone evaluation are underlined.

Despite rapid progress, learning representations that simultaneously preserve _dense_ spatio-temporal structure (needed for localization, geometry, and tracking) while also capturing _dynamics_ and supporting _global_ understanding (needed for high-level recognition) remains an open challenge.
Among recent advances, Joint Embedding Predictive Architectures (JEPA) (LeCun, 2022)—and in particular the V-JEPA family (Bardes et al., 2024; Assran et al., 2025)—have demonstrated strong global video understanding, especially in settings that require modeling motion and dynamics, and have shown promise for enabling prediction and planning in embodied agents (Assran et al., 2025). However, as illustrated in Figure [1](#S0.F1), their learned representations can be less amenable to extracting fine-grained local spatial structure. In contrast, other SSL approaches such as DINO (Caron et al., 2021; Oquab et al., 2023; Siméoni et al., 2025) yield high-quality dense features for detection and segmentation, but are primarily image-based and therefore do not directly learn temporal dynamics from video.

In this work, we study self-supervised learning with a latent mask-denoising objective, where the model predicts masked segments of an image or video directly in a learned representation space. Our central finding is that high-quality _dense_ spatio-temporal features—preserving fine-grained spatial layout and motion dynamics—do not emerge reliably when the prediction loss is applied only to masked regions. Instead, extending the predictive loss to the _entire_ input, both masked and unmasked segments, substantially improves the low-level (dense) representations.

Building on this insight, we introduce V-JEPA 2.1, a self-supervised approach for learning unified image and video representations. V-JEPA 2.1 uses a _dense predictive loss_ applied to _all tokens_ (both visible context and masked tokens), grounding each token in its spatio-temporal location and preventing visible tokens from acting as global aggregators—an effect that is key to _improving_ dense feature quality (Figure [3](#S2.F3)). Additionally, we find that _deep self-supervision_—applying the loss hierarchically at multiple intermediate encoder layers to provide training signals throughout the network—yields consistent gains on both dense and global downstream tasks. To enable native joint training across modalities, we use modality-specific learned tokenizers for images and videos within a single shared encoder. Finally, we show these improvements scale with data and model capacity: expanding the image component from 1M to 142M images using VisionMix-163M and scaling the model from 300M to 2B parameters leads to systematic downstream gains.

We train and release a suite of V-JEPA 2.1 models (ViT-g/G, 1B/2B), along with two distilled, smaller variants (ViT-B/L, 80M/300M). Empirically, V-JEPA 2.1 achieves state-of-the-art performance on _predictive_ video benchmarks spanning both fine-grained and semantic forecasting: it reaches 7.71 mAP on Ego4D short-term object-interaction anticipation, which requires predicting _where_ and _when_ interactions will occur (localized interaction regions and time-to-interaction), and 40.8 Recall@5 on EPIC-KITCHENS-100 action anticipation, which evaluates the ability to forecast upcoming actions from partial temporal context.

We further show that better dense-features also improves performances on world modelling tasks. V-JEPA 2.1 dense-features leads to +20% success rate compared to VJEPA-2 AC (Assran et al., 2025) on grasping when when deploy our model on real Franka arms in new environment zero-shot. V-JEPA 2.1 is also suitable for robot navigation where it achieves state-of-art performances (5.687 ATE on Tartan Drive) while having 10x faster planning speed compared to previous work (Bar et al., 2025).

Beyond prediction and planning, V-JEPA 2.1 also delivers strong performance in both _dense_ and _global_ understanding tasks. For dense tasks, V-JEPA 2.1 ViT-G sets a new state of the art in linear-probe monocular depth estimation (0.307 RMSE on NYUv2), achieves competitive linear-probe semantic segmentation (85.0 mIoU on Pascal VOC), and produces temporally consistent features for video object segmentation (72.7 $\mathcal{J}\&\mathcal{F}$-Mean on YouTube-VOS). At the global level, it also attains state-of-the-art accuracy in action recognition (77.7% on Something-Something-v2) and achieves competitive performances in Video Question Answering (VQA) tasks (83.1 accuracy on PerceptionTest).

We hope that these contributions will foster research in learning strong representations for physical world modelling, while empowering many applications in video understanding. We make our code and pretrained models publicly available to facilitate further research and applications.

<a id="section-2"></a>

## 2 Methodology

<a id="section-2-1"></a>

### 2.1 Preliminaries: Joint-Embedding Predictive Architectures

Joint-Embedding Predictive Architecture (JEPA) (LeCun, 2022) is a self-supervised learning framework designed to learn representations of data by making predictions in a learned latent space, rather than directly in the observation (input) space.
JEPA models operate by encoding both a noise-corrupted version and an uncorrupted (clean) version of the same input. A predictor network is then trained to predict the representation of the clean input from the representation of the corrupted input.

Corrupted and clean inputs are processed by the encoder $E_{\theta}(\cdot)$, which produces latent representations.
The predictor, $P_{\phi}(\cdot)$, is then used to map the representation of the corrupted input to the representation of the clean input. Given that the encoder and predictor are learned simultaneously, the system admits a trivial and uninformative solution in which the encoder $E_{\theta}(\cdot)$ outputs a constant vector regardless of its input.
To avoid this representation collapse, explicit (Bardes et al., 2021; Balestriero and LeCun, 2025; Mo and Tong, 2024) or implicit (Grill et al., 2020a; Assran et al., 2023) regularization is used to promote representations that preserve input information.

In this work, we build upon the V-JEPA family of models, where video representations are learned through a mask-denoising objective in the representation space (Bardes et al., 2024; Assran et al., 2025).
The V-JEPA objective aims to predict the representation of a video $y$ from another view $x$ of that video that has been corrupted through masking, i.e., from which patches have been randomly dropped.
The encoder $E_{\theta}(\cdot)$ processes the masked video $x$, and outputs an embedding vector, or context tokens, for each visible patch. The
outputs of the encoder are concatenated with a set of learnable mask tokens $\Delta_{y}$ that specify the spatio-temporal position of the masked patches. The predictor network processes the combined tokens sequence, and outputs an embedding vector for each input token.
The encoder and predictor are trained by minimizing the following objective:

$$
\mathcal{L_{\text{predict}}}=\frac{1}{|M|}\sum_{i\in M}\|P_{\phi}(E_{\theta}(x),\Delta_{y})_{i}-\mathrm{sg}(E_{\overline{\theta}}(y)_{i})\|_{1},(1)
$$

where $M$ is a set containing the masked patch indexes from the $x$ view.
The loss use a stop-gradient operator, $\mathrm{sg}$, to prevent representation collapse (Grill et al., 2020b) and an exponential moving average $\overline{\theta}$ of $\theta$ is used to update the weight of the encoder $E_{\overline{\theta}}(y)$ processing the video $y$. $\mathcal{L_{\text{predict}}}$ is only applied on masked tokens, and not on the context tokens.

Both encoder $E_{\theta}(\cdot)$ and predictor $P_{\phi}(\cdot)$ are parametrized with Vision Transformer (Dosovitskiy, 2020) and we rely on the same masking strategy as Assran et al. (2025). Refer to Appendix [6](#S6) for more details.

<a id="section-2-2"></a>

### 2.2 Analysis of V-JEPA Features for Dense Vision Tasks

While V-JEPA has proven to be an effective approach for understanding global semantic information from video, predicting future actions, and planning to reach specific goals (Bardes et al., 2024; Assran et al., 2025), previous works have not investigated the suitability of V-JEPA 2 features for dense vision tasks. To address this gap, we analyze the V-JEPA 2 feature maps through qualitative visualizations and dense downstream tasks evaluation.

For the qualitative visualizations, we compute the Principal Component Analysis (PCA) of patch features extracted from the V-JEPA 2 encoder, and we map the first three components to the RGB color channels.
We assess the encoder performance on dense tasks using a linear probing protocol, in which we train a single linear layer on top of the frozen encoder features. We evaluate V-JEPA 2 on semantic segmentation using the ADE20K dataset (Zhou et al., 2017a) and depth estimation on NYUv2 (Silberman et al., 2012b). Refer to Appendix [8](#S8) for more details on the evaluation setup.

##### Observations and Hypothesis.

<a id="figure-3"></a>

![step92_img](images/step92_img.png)

> Figure 3: Influence of the context loss $\mathcal{L}_{ctx}$. We show PCA visualizations of the feature map representations learned with V-JEPA 2 and with a model trained using V-JEPA 2 plus our $\mathcal{L}_{ctx}$ loss. While V-JEPA features only show fragmented local spatial structure, explicitly supervising unmasked regions with $\mathcal{L}_{ctx}$ leads to feature maps that exhibit coherent spatial structure. Similar semantic parts (e.g., heads of dogs, wheels of cars) are mapped to the same PCA components.

Feature map visualizations of V-JEPA 2 are shown in Figure [1](#S0.F1) and Figure [3](#S2.F3). We observe that feature maps are noisy and show only fragmented local spatial structure. Additionally, V-JEPA 2 features obtain limited performance on dense tasks when using a simple linear probing protocol, such as semantic segmentation (22.2 mIoU on ADE20K) or depth estimation (0.682 RMSE on NYUv2), as reported in Table [2.3](#S2.SS3.SSS0.Px3). Overall, these results support the conclusion that local information about the visual scene is not easily extractable from the V-JEPA 2 representation.

We hypothesize that the absence of local structure in the feature maps is due to the lack of self-supervision on patches that are not masked, i.e. the context patches.
The predictor $P_{\phi}(\cdot)$ takes as input the concatenation of context tokens computed by $E_{\theta}(x)$ and a set of mask tokens $\Delta_{y}$ that specify the masked positions to predict. The predictor outputs one token for each input, i.e., for both context and masked tokens. However, the original loss from V-JEPA 2 (Assran et al., 2025) is applied only to the masked tokens, as Equation [1](#S2.E1) shows.
Therefore, the model has no incentive to encode local information within the context tokens and can instead devote this computation to aggregating global information to minimize $\mathcal{L_{\text{prediction}}}$, similarly to register tokens (Darcet et al., 2023).

##### Context Self-Supervision.

To verify this hypothesis, we propose to self-supervise both the mask and context patches and introduce a context loss $\mathcal{L}_{\text{ctx}}$, which is a weighted version of $\mathcal{L}_{\text{predict}}$ applied on the context tokens:

$$
\mathcal{L_{\text{context}}}=\frac{1}{|C|}\sum_{i\in C}\lambda_{i}\|P_{\phi}(E_{\theta}(x),\Delta_{y})_{i}-\mathrm{sg}(E_{\overline{\theta}}(y)_{i})\|_{1},(2)
$$

where $C$ is the set of indexed context tokens, and $\lambda_{i}$ is a patch-specific weighting parameter described in the next section. The model is trained to minimize $\mathcal{L}_{\text{predict}}+\mathcal{L}_{\text{ctx}}$. Figure [3](#S2.F3) shows that adding $\mathcal{L}_{\text{ctx}}$ has a significant effect on the learned feature maps. With the context loss, local structure now clearly appears in the feature maps, and similar semantic parts (e.g., head of the dogs, wheel of the car) are mapped to the same PCA components. Additionally, adding $\mathcal{L}_{\text{ctx}}$ significantly improves performance on dense-prediction tasks, achieving $33.9$ mIoU on ADE20K (up from $22.2$), and $0.473$ RMSE on NYUv2 (down from $0.682$). Hence, those results validate that by explicitly supervising context tokens, the model learns features that encode coherent local structure.

<a id="section-2-3"></a>

### 2.3 V-JEPA 2.1: Improving Dense Video SSL Features

Building on the previous observation, we introduce V-JEPA 2.1, a self-supervised training recipe for learning representations that combine high-quality dense local features with global semantic understanding.
Our key algorithmic innovations are (1) Dense Prediction loss that applies self-supervision on both masked and unmasked tokens (Section [2.3.1](#S2.SS3.SSS1)) and, (2) Deep Self-Supervision of the encoder intermediate layers via a multi-level predictor (Section [2.3.2](#S2.SS3.SSS2)).
Additionally, we explore (3) a Multi-Modal Tokenizer with modality-specific patch embeddings for images and videos (Section [2.3.4](#S2.SS3.SSS4)); (4) Data Scaling through a more diverse and balanced image–video training distribution (Section [2.3.3](#S2.SS3.SSS3)); and Model Scaling to ViT-G (Section [2.3.5](#S2.SS3.SSS5)), enabling state-of-the-art downstream performance and effective distillation to smaller models (ViT-L, ViT-B, Section [3.10](#S3.SS10)).

<a id="figure-4"></a>

![architecture_vjepa2_1](images/architecture_vjepa2_1.jpg)

> Figure 4: V-JEPA 2.1 Detailed Architecture. Images and videos are processed by respectively either a 2D or 3D Convolutional patch embedding. Then, 3D Rotational Positional Encoding (RoPE) and learnable modality embedding are added. The $x-$encoder processes the visible tokens and outputs multi-level embeddings formed by concatenating the normalized output from intermediate encoder blocks. Then, a MLP fuses this multi-level representation and reduces its dimensionality. These context tokens are concatenated with learnable mask tokens carrying spatio-temporal positional information. The predictor processes the combined sequence and produces multi-level predictions for the masked tokens. Training uses two different losses: (i) an L1 loss on masked-token predictions (the original V-JEPA objective), and (ii) a distance-weighted L1 loss on nearby context tokens, both supervised using the $y$-encoder multi-level outputs.

##### VJEPA 2.1 Architecture.

We illustrate the V-JEPA 2.1 architecture in Figure [4](#S2.F4).
An input, either an image or a video, is projected into a sequence of embedding vectors, or tokens, using a modality-specific patch embedding. Mask corruption is then applied to the sequence by randomly dropping patch tokens.
The $x$-encoder processes the remaining visible context tokens and outputs representations from multiple encoder levels in addition to the final output. The multi-level representations are then concatenated along the channel axis and fed to an MLP to reduce their dimensionality. Context tokens are concatenated, along the sequence axis, with learnable mask tokens that carry spatio-temporal positional information of the masked patches. The predictor processes the combined sequence and produces multi-level predictions for each token.
Training uses two different losses: (i) an L1 loss on masked-token predictions (the original V-JEPA objective), and (ii) a distance-weighted L1 loss for context tokens. Both use the $y$-encoder outputs as targets, which process the unmasked sequence of patches from the input images or videos. Losses are applied to several intermediate representation levels in addition to the encoder output.

##### Implementation Details.

We follow the warmup-constant learning rate schedule of V-JEPA 2 and we train models for 135,000 iterations. We maintain the teacher EMA coefficient and weight decay at fixed values. Each video sample is a clip of 16 frames at a resolution of $256\times 256$, and each image sample has a resolution of $256\times 256$.
Additionally, in a second stage we explore the effect of applying a cool-down phase, i.e., decaying the learning rate and increasing the input images and videos resolution. We further train our models for 12,000 iterations during this cool-down phase, increasing the input resolution: video clips now have 64 frames at a resolution of $384\times 384$, and images have a resolution of $512\times 512$.
Ablation results are reported after the first training phase, whereas final downstream tasks results use the full warmup–constant–cooldown schedule.
More details and all hyper-parameters are provided in Appendix [6](#S6).

##### Empirical Evaluation.

To evaluate our design choice, we rely on a set of dense-vision tasks (ADE20K and NYUv2) using a linear probing evaluation protocol following Siméoni et al. (2025) and global recognition tasks (Something-Somethingv2 for action recognition and ImageNet for object recognition) with an attentive probing protocol following Assran et al. (2025).
We ablate the effect of each architecture component in Figure [5](#S2.F5) and Table [2.3](#S2.SS3.SSS0.Px3).
In the following, we describe each component in more detail, as well as their impact on downstream performance.

<a id="figure-5"></a>

![step92_features](images/step92_features.png)

> Figure 5: Impact of individual components of our novel V-JEPA 2.1 training recipe. The ablation is conducted starting from a ViT-L architecture, on single-image semantic segmentation on ADE20k, and action classification on SSv2. Introducing Weighted-Context Self-Supervision with the context loss significantly improves segmentation, at the cost of classification. Deep Self-Supervision allows to retrieve the performance, and further improving segmentation. Scaling the image data with VisionMix 163M dataset, combined with a Multi-Modal Tokenizer further improve the results. Finally, the recipe scales with model size and high resolution cool-down.

![step105_features](images/step105_features.png)

> Table 1: Impact of individual components of our novel V-JEPA 2.1 training recipe. Results on image classification (IN1K), video classification (SSv2), depth estimation (NYU), and semantic segmentation (ADE20K). Introducing the Context Loss improves dense tasks but reduces classification performance on SSv2. Incorporating our Deep Self-Supervision restores the classification performance. The VisionMix 163M dataset, the Multi-Modal Tokenizer, and scaling model size further improve the results.

#### 2.3.1 Dense Prediction Loss

We propose applying our self-supervised loss to both masked and visible patches by minimizing $\mathcal{L_{\text{dense}}}=\mathcal{L}_{\text{predict}}+\mathcal{L}_{\text{ctx}}$, where $\mathcal{L}_{\text{predict}}$ is defined in Eq. [1](#S2.E1) and $\mathcal{L}_{\text{ctx}}$ is defined in Eq. [2](#S2.E2). Naive application of $\mathcal{L}_{\text{ctx}}$ loss leads to poor performance on global semantic tasks, as the system can potentially find trivial solutions, such as copying the context features.
We therefore explore various weighting coefficients $\lambda_{i}$ in Eq. [2](#S2.E2). Table [2.3](#S2.SS3.SSS0.Px3) presents an ablation on various weighting schemes. First, we experiment with fixed values and set all $\lambda_{i}$ to a constant $\lambda$ and try values in the range $\lambda=[0.0,0.05,0.2,0.5,1.0]$. We observe that as we increase $\lambda$, the performance in semantic segmentation in the ADE20k dataset increases significantly up to certain point, but at the cost of the performance in action recognition in the SSv2 dataset decreases.
We then introduce a progressive warm-up of $\lambda$ to restore action-recognition performance, with a schedule from epochs 50–100. We found empirically that it greatly stabilizes training.
Following, we introduce a dynamic weighting scheme where $\mathcal{L}_{\text{ctx}}$ for a given patch $i$ is weighted by the inverse square root of its minimum spatio-temporal distance to any masked token in the video sequence: i.e. setting

$$
\lambda_{i}=\frac{\lambda}{\sqrt{\text{d}_{\text{min}}(i,M)}}(3)
$$

in $\mathcal{L}_{\text{ctx}}$ in Eq. [2](#S2.E2), where $\text{d}_{\text{min}}$ is the distance, in number of blocks, between a context token and its closest mask token. This weighting emphasizes patches near masked regions by enforcing local continuity between masked and context areas, yielding a good trade-off between segmentation and action recognition performance.

Introducing our novel context loss $\mathcal{L}_{ctx}$ with our weighted scheme improves the performance on dense vision tasks (22.2 $\rightarrow$ 33.9 mIoU on ADE20k, 0.682 $\rightarrow$ 0.473 RMSE on NYUv2). Qualitatively, this loss smooths the feature maps by removing noisy artifacts, as shown in Figure [3](#S2.F3).
However, Table [2.3](#S2.SS3.SSS0.Px3) shows that there is still a degradation in video understanding (72.8 $\rightarrow$ 62.5 on SSv2) and image classification (82.2 $\rightarrow$ 72.6 on IN1K).

#### 2.3.2 Deep Self-Supervision

We self-supervise the encoder representation not only at the output but also at multiple intermediate levels. We first concatenate, along the channel dimension, the outputs of three intermediate $x$-encoder blocks, in addition to the output layer. Then, a lightweight MLP fuses these multi-level representations and reduces their dimensionality before feeding them into the predictor. The predictor processes the fused multi-level sequence of context and mask tokens and produces four outputs corresponding to the four encoder layers. Both the prediction loss and the context loss are then applied at each one of these four levels.

Deep Self-Supervision leads to significant improvement on downstream performance for both global and dense tasks, as shows Figure [5](#S2.F5).
Furthermore, it allows local information to flow towards the final layers, effectively removing the need for intermediate layers in dense downstream tasks as we show in Appendix [9.1](#S9.SS1).
Deep Self-Supervision allows to recover the global understanding capabilities of V-JEPA 2 (72.0 on SSv2, 80.8 on IN1K) while improving on dense tasks with the context loss (38.6 mIoU on ADE20K, 0.463 RMSE on NYU).

#### 2.3.3 Scaling Image Data.

DINOv2 (Oquab et al., 2023) introduced a cluster-based retrieval strategy to select images from a large pool of raw internet data, resulting in a curated set of 142 million images, referred to as the LVD-142M dataset.
Using a similar approach, V-JEPA 2 (Assran et al., 2025) collected and curated video scenes from YT1B videos (Zellers et al., 2022), combined with other publicly available video datasets, yielding a large-scale collection of 19 million video samples from the internet, corresponding to $1.6$ million hours. Both works demonstrated the positive effect of data scaling for SSL pretraining.

Building on these insights, we construct our VisionMix163M Dataset, combining large-scale curated sources from these two prior works. As we show in Table LABEL:tab:\_datasets, we replace the 1M-image ImageNet subset from VJEPA-2 pretraining data with LVD-142M, providing a broader and more diverse appearance distribution.
Since this extensive image collection already covers many static visual concepts, we shift the video sampling strategy towards more dynamic, motion-rich content, increasing the SSv2 sampling weight from 0.056 to 0.170.
We also found beneficial to increase the contribution of YT-1B from 0.188 to 0.720, which contains much more heterogeneous video samples.

Rather than mixing images and videos within the same training batch, we leverage distributed training by assigning separate workers to each modality. After each iteration, gradients from video-only and image-only nodes are aggregated before updating the model.
The image/video ratio is controlled through per-modality batch sizes.
Empirically, we found optimal performance with 128 video clips (16 frames each) and 2,304 images per global batch. As we report in Table [2.3](#S2.SS3.SSS0.Px3), the improvement of training on a more diverse and extend database is beneficial in all tasks (72.1 $\rightarrow$ 72.6 on SSv2, 80.8 $\rightarrow$ 81.6 on ImageNet, 38.6 $\rightarrow$ 40.8 on ADE20K, 0.463 $\rightarrow$ 0.418 RMSE on NYUv2).

<a id="table-3"></a>

> Table 3: Comparison between VideoMix22M and VisionMix163M. We increase the visual diversity of the pretraining dataset by increasing the number of images, replacing ImageNet with LVD-142M, and update the YT-1B sampling weight to promote data-source with more visual diversity.

| Source                           | Samples | Type           | Total Hours | V-JEPA2<br>weights | V-JEPA2.1<br>weights |
| -------------------------------- | ------- | -------------- | ----------- | ------------------ | -------------------- |
| Source                           | Samples | Type           | Total Hours | V-JEPA2<br>weights | V-JEPA2.1<br>weights |
| Source                           | Samples | Type           | Total Hours | V-JEPA2<br>weights | V-JEPA2.1<br>weights |
| Source                           | Samples | Type           | Total Hours | V-JEPA2<br>weights | V-JEPA2.1<br>weights |
| Source                           | Samples | Type           | Total Hours | V-JEPA2<br>weights | V-JEPA2.1<br>weights |
| Source                           | Samples | Type           | Total Hours | V-JEPA2<br>weights | V-JEPA2.1<br>weights |
| SSv2 (Goyal et al., 2017)        | 168K    | EgoVideo       | 168         | 0.056              | 0.170                |
| SSv2 (Goyal et al., 2017)        | 168K    | EgoVideo       | 168         | 0.056              | 0.170                |
| SSv2 (Goyal et al., 2017)        | 168K    | EgoVideo       | 168         | 0.056              | 0.170                |
| SSv2 (Goyal et al., 2017)        | 168K    | EgoVideo       | 168         | 0.056              | 0.170                |
| SSv2 (Goyal et al., 2017)        | 168K    | EgoVideo       | 168         | 0.056              | 0.170                |
| SSv2 (Goyal et al., 2017)        | 168K    | EgoVideo       | 168         | 0.056              | 0.170                |
| Kinetics (Carreira et al., 2019) | 733K    | ExoVideo       | 614         | 0.188              | 0.010                |
| Kinetics (Carreira et al., 2019) | 733K    | ExoVideo       | 614         | 0.188              | 0.010                |
| Kinetics (Carreira et al., 2019) | 733K    | ExoVideo       | 614         | 0.188              | 0.010                |
| Kinetics (Carreira et al., 2019) | 733K    | ExoVideo       | 614         | 0.188              | 0.010                |
| Kinetics (Carreira et al., 2019) | 733K    | ExoVideo       | 614         | 0.188              | 0.010                |
| Kinetics (Carreira et al., 2019) | 733K    | ExoVideo       | 614         | 0.188              | 0.010                |
| Howto100M (Miech et al., 2019)   | 1.1M    | ExoVideo       | 134K        | 0.318              | 0.100                |
| Howto100M (Miech et al., 2019)   | 1.1M    | ExoVideo       | 134K        | 0.318              | 0.100                |
| Howto100M (Miech et al., 2019)   | 1.1M    | ExoVideo       | 134K        | 0.318              | 0.100                |
| Howto100M (Miech et al., 2019)   | 1.1M    | ExoVideo       | 134K        | 0.318              | 0.100                |
| Howto100M (Miech et al., 2019)   | 1.1M    | ExoVideo       | 134K        | 0.318              | 0.100                |
| Howto100M (Miech et al., 2019)   | 1.1M    | ExoVideo       | 134K        | 0.318              | 0.100                |
| ImageNet (Deng et al., 2009)     | 1M      | Images         | n/a         | 0.250              | 0.                   |
| ImageNet (Deng et al., 2009)     | 1M      | Images         | n/a         | 0.250              | 0.                   |
| ImageNet (Deng et al., 2009)     | 1M      | Images         | n/a         | 0.250              | 0.                   |
| ImageNet (Deng et al., 2009)     | 1M      | Images         | n/a         | 0.250              | 0.                   |
| ImageNet (Deng et al., 2009)     | 1M      | Images         | n/a         | 0.250              | 0.                   |
| ImageNet (Deng et al., 2009)     | 1M      | Images         | n/a         | 0.250              | 0.                   |
| YT-1B (Zellers et al., 2022)     | 19M     | ExoVideo       | 1.6M        | 0.188              | 0.720                |
| YT-1B (Zellers et al., 2022)     | 19M     | ExoVideo       | 1.6M        | 0.188              | 0.720                |
| YT-1B (Zellers et al., 2022)     | 19M     | ExoVideo       | 1.6M        | 0.188              | 0.720                |
| YT-1B (Zellers et al., 2022)     | 19M     | ExoVideo       | 1.6M        | 0.188              | 0.720                |
| YT-1B (Zellers et al., 2022)     | 19M     | ExoVideo       | 1.6M        | 0.188              | 0.720                |
| YT-1B (Zellers et al., 2022)     | 19M     | ExoVideo       | 1.6M        | 0.188              | 0.720                |
| LVD-142M (Oquab et al., 2023)    | 142 M   | Curated images | n/a         |                    |                      |
| LVD-142M (Oquab et al., 2023)    | 142 M   | Curated images | n/a         |                    |                      |
| LVD-142M (Oquab et al., 2023)    | 142 M   | Curated images | n/a         |                    |                      |
| LVD-142M (Oquab et al., 2023)    | 142 M   | Curated images | n/a         |                    |                      |
| LVD-142M (Oquab et al., 2023)    | 142 M   | Curated images | n/a         |                    |                      |
| LVD-142M (Oquab et al., 2023)    | 142 M   | Curated images | n/a         |                    |                      |

#### 2.3.4 Multi-Modal Tokenizer

Previous work exploring joint training on image and video, such as V-JEPA 2, was suboptimal: it employed a single 3D convolution as the patch-embedding layer. Images were duplicated temporally and treated as a 16-frame static video, which significantly increased their computational cost and introduced an incorrect representational bias (i.e., images were interpreted as static videos).
Instead, we introduce a multi-modal tokenizer, which applies a 3D convolution of $16\times 16\times 2$ for processing videos and a 2D convolution of $16\times 16$ for images.
We also add a modality-learnable token to both the encoder and the predictor inputs, which explicitly encodes whether the input comes from the image or video pathway. These learnable tokens condition the processing on the input modality, helping the model disentangle stronger static appearance cues in images and temporal motion information in videos.

This design allows each modality to be processed in its native form, eliminating the need for temporal duplication of images and improving computational efficiency. Additionally, we observe that using the Multi-Modal Tokenizer has a positive effect on dense-task performance: it improves mIoU on ADE20K from $40.8$ to $41.4$, while performance on action or object recognition remains stable.

#### 2.3.5 Scaling Model Size to ViT-G (2B) and High-Resolution Cool-Down

Next, we explore the effect of model scaling and high-resolution cooldown. Scaling the V-JEPA encoder from a ViT-L with 300 million parameters to a ViT-G with 2 billion parameters leads to significant improvements on all downstream tasks (72.6 $\rightarrow$ 76.1 on SSv2, 81.6 $\rightarrow$ 84.8 accuracy on ImageNet, 41.4 $\rightarrow$ 47.1 mIoU on ADE20K, 0.415 $\rightarrow$ 0.365 RMSE on NYUv2).

Additionally, introducing a cool-down phase for the learning rate, during which we increase both the spatial resolution of images (from $256\times 256$ to $512\times 512$) and the spatio-temporal resolution of videos (from 16 frames at $256\times 256$ to 64 frames at $384\times 384$), further improves performance on all tasks.
This achieves an accuracy of $77.7$ on SSv2, $85.5$ on ImageNet, an mIoU of $47.9$ on ADE20K, and an RMSE of $0.307$ on NYUv2, resulting in our best performing model.
The benefits of a cool-down training phase are particularly strong in depth estimation (0.365 $\rightarrow 0.307$ RMSE on NYUv2).

#### 2.3.6 Model Distillation

We scaled the size of the model not only to achieve top-tier performance but also to enable effective compression of the model through distillation Hinton et al. (2015). We distill our ViT-G (2B) model into smaller variants (ViT-B, 80M; ViT-L, 300M). The distillation protocol is adapted from our pretraining recipe, with key differences: i) we replace the Exponential-Moving-Average (EMA) of the target encoder by a frozen teacher model, ii) we keep an EMA copy of the student encoder, that is not used in the loss, but serves as the final model, iii) the distillation loss is identical to our pretraining loss, except it is only computed on the last layer of the teacher encoder, and it does not use deep self-supervision, iv) we use a predictor with only 12 blocks and a final linear layer matching the teacher embedding dimension. All other hyper-parameters—including masking ratios, cool-down schedules, learning rates, and data augmentations—remain identical to the original pretraining recipe. We provide more details on the distillation protocol in Appendix [7](#S7).

<a id="section-3"></a>

## 3 Results

In this section, we evaluate the performance of V-JEPA 2.1 on a large variety of downstream tasks. Throughout the experiments, we employ V-JEPA 2.1 as a frozen encoder, demonstrating the versatility of its features.
We first demonstrate the predictive capabilities of V-JEPA 2.1 in two forecasting tasks: short-term object interaction anticipation (Section [3.1](#S3.SS1)) and action anticipation (Section [3.2](#S3.SS2)).
We then demonstrate that can leverage V-JEPA 2.1 to learn an action-condition world model and performs robot manipulation (Section [3.3](#S3.SS3)) and navigation tasks (Section [3.4](#S3.SS4)) in zero-shot setup.
Then, we evaluate the quality of the learned dense features by assessing the V-JEPA 2.1 performance on single-image depth estimation and semantic segmentation (Section [3.5](#S3.SS5)).
Following, we analyze the temporal consistency of V-JEPA 2.1 representations through the video object segmentation task (Section [3.5](#S3.SS5)).
We also analyze V-JEPA 2.1 global understanding on two high-level understanding tasks: probe-based video classification and image classification (Section [3.7](#S3.SS7)).
Finally, we present results for our smaller distilled models (Section [3.10](#S3.SS10)).
We provide more details on the experimental setup and all pretraining hyper-parameters in Appendices [6](#S6) and [8](#S8).

<a id="section-3-1"></a>

### 3.1 Short-Term Object Interaction Anticipation

<a id="figure-6"></a>

![sta_diagram.drawio](images/sta_diagram.drawio.png)

> Figure 6: Short-Term Anticipation task. Given a video observed up to time $t$ (denoted $V_{:t}$), the model predicts a set of future object–interaction events. Each prediction includes: (i) a bounding box localizing the object that will be interacted with, (ii) the noun class of that object, (iii) a verb class describing the upcoming interaction, and (iv) the anticipation time $\delta$, i.e., the number of seconds between the current frame and the start of the interaction. Ground-truth labels are derived from the contact frame $V_{t+\delta}$, but are expressed in the coordinate frame of the last observed frame $V_{t}$.

<a id="table-4"></a>

> Table 4: Short-Term Object Interaction Anticipation on Ego4D. Following Grauman et al. (2022), we report different Top-5 Average Precision (AP) and mean Average Precision (mAP) metrics, where the winning score is the mAP All. We compare results reported in the literature with different frozen SSL encoders (DINOv2, DINOv2, V-JEPA 2 and our V-JEPA 2.1) extended with an attentive-based predicted head. V-JEPA 2.1 obtains the state-of-the-art due to its high-quality dense features and predictive capabilities.

| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| ------------------------------------ | ------- | --------- | --------- | ---------------- | ----------- | ------------------ | ------------------ | --------- | -------- | ---------- | ----------------- | ---------- |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Model                                | AP<br>b | AP<br>b+N | AP<br>b+V | AP<br>b+$\delta$ | AP<br>b+N+V | AP<br>b+$\delta$+N | AP<br>b+$\delta$+V | AP<br>All | mAP<br>N | mAP<br>N+V | mAP<br>N+$\delta$ | mAP<br>All |
| Results Reported in the Literature   |         |           |           |                  |             |                    |                    |           |          |            |                   |            |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| StillFast (Ragusa et al., 2023)      | -       | -         | -         | -                | -           | -                  | -                  | -         | 20.2     | 10.3       | 7.17              | 3.96       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| STAformer (Mur-Labadia et al., 2024) | 38.3    | 28.3      | 16.6      | 12.27            | 12.8        | 8.89               | 5.47               | 4.06      | 29.4     | 15.3       | 9.94              | 5.67       |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| GANO (Thakur et al., 2023)           | 45.3    | 27.0      | 12.2      | 16.6             | 6.54        | 9.0                | 4.18               | 2.47      | -        | -          | -                 | -          |
| Encoders using our same protocol     |         |           |           |                  |             |                    |                    |           |          |            |                   |            |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-L (Oquab et al., 2023)    | 45.1    | 37.8      | 21.9      | 14.4             | 17.6        | 10.6               | 7.27               | 5.25      | 28.3     | 15.2       | 9.22              | 5.25       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv2 ViT-g (Oquab et al., 2023)    | 47.8    | 38.1      | 23.6      | 14.1             | 19.1        | 10.9               | 7.29               | 5.73      | 30.6     | 16.8       | 9.37              | 5.44       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-H+ (Siméoni et al., 2025) | 48.9    | 40.2      | 23.4      | 13.6             | 19.4        | 10.8               | 6.71               | 5.45      | 32.4     | 17.2       | 9.53              | 5.20       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| DINOv3 ViT-7B (Siméoni et al., 2025) | 50.2    | 40.9      | 23.8      | 14.2             | 19.8        | 11.5               | 7.33               | 5.82      | 33.8     | 17.4       | 10.3              | 5.68       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 45.7    | 34.4      | 22.2      | 16.7             | 16.9        | 12.1               | 8.56               | 6.26      | 27.2     | 14.9       | 10.4              | 6.02       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-g                     | 47.3    | 36.5      | 23.6      | 18.1             | 18.2        | 13.5               | 9.55               | 7.21      | 28.7     | 15.5       | 11.4              | 6.75       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |
| V-JEPA 2.1 ViT-G                     | 50.7    | 39.3      | 25.8      | 20.2             | 20.3        | 15.1               | 10.8               | 8.20      | 30.9     | 17.2       | 12.8              | 7.71       |

Short-Term object-interaction Anticipation (STA) consists in predicting future object interaction in a ego-centric scenario, predicting the next active object bounding box $b$, the object noun category $N$ the action verb $V$ and the time until contact ($\delta$).
This formulation evaluates fine-grained 2D localization, semantic understanding of objects, temporal reasoning over video dynamics, and the ability to forecast user intentions.
Using the Ego-4D STA benchmark (Grauman et al., 2022), we show that V-JEPA 2.1 outperforms previous state-of-the-art performance by a significant margin due to its high-quality dense features and predictive capabilities.

##### Task.

We evaluate V-JEPA 2.1 on the STA v2 split of Ego4D (Grauman et al., 2022), which comprises 243 hours of annotated video clips spanning 128 noun and 81 verb categories, with a total of 98,276 training and 47,395 validation samples.
We compare against state-of-the-art methods (Ragusa et al., 2023; Mur-Labadia et al., 2024; Thakur et al., 2023), and we further asses the performance of DINOv2 (Darcet et al., 2023) and DINOv3 (Siméoni et al., 2025) image encoders using our proposed attentive probe.
Following the evaluation protocol of Grauman et al. (2022), we report Top-5 Average Precision (AP) and Top-5 mean Average Precision (mAP) metrics. As in standard mAP, predictions are matched to ground-truth boxes using IoU > 0.5 and additional class-specific criteria. For instance, the Top-5 mAP All variant requires a correct noun, correct verb, IoU above 0.5, and a time-to-contact $\delta$ prediction within a 0.25-second tolerance. To address the inherently multi-modal nature of future anticipation—where multiple plausible next-active objects may exist—the metric discounts up to four highest-scoring false positives per example, thereby avoiding penalties for plausible but unannotated predictions.
Additionally, we report individual metrics to evaluate the temporal ($\delta$), spatial (bounding boxes), and semantic (noun and verb) dimensions of the task.

<a id="figure-7"></a>

![3b609b23-f91d-43da-9918-ce928181f53f_0007244](images/3b609b23-f91d-43da-9918-ce928181f53f_0007244.jpg)

> Figure 7: Short-Term Anticipation (STA) qualitative results. We compare our model predictions with the ground-truth data. V-JEPA 2.1 predicts multiple scenarios, where the predicted object and verb classes correspond with plausible human-object interactions.

##### Evaluation protocol.

The model receives as input a low-resolution video clip (384 px, 8 frames spanning 0.5 seconds) and a high-resolution image (1080 px) corresponding to the last frame of the clip. Using the frozen encoder of V-JEPA 2.1, we extract last-level features independently from both inputs using the respective patchifier (a 2D convolution for the high-resolution image and a 3D convolution for the video) and adding the corresponding modality embedding.
For the video features, we train a four-layer attentive probe, followed by the frame-guided temporal pooling module from Mur-Labadia et al. (2024). This module aggregates the 3D video tokens into a 2D representation that is spatially aligned with the spatial reference of the last frame.
The pooled video features are then summed to the image features, and the resulting fused representation is rescaled into four multiscale feature maps, which serve as input to the detection head.
To ensure a fair comparison with state-of-the-art methods (Ragusa et al., 2023; Mur-Labadia et al., 2024; Thakur et al., 2023), we adopt the same detection head (Ragusa et al., 2023) utilized in these approaches. This head extends Faster R-CNN by adding linear layers to additionally predict the verb category and the time to contact.

##### Results.

Table [4](#S3.T4) presents a comparison with state-of-the-art methods on the Short Term Anticipation task. V-JEPA 2.1 demonstrates achieves the absolute state-of-the-art performance with an overall mAP of 7.71. This represents a relative improvement of approximately 35$\%$ over the previous best method (Mur-Labadia et al., 2024), which introduces task-specific training components.
As it is shown by the individual metrics, this gain is primarily driven by improved understanding of the next action 25.8 APb+V and the time to contact 20.20 APb+$\delta$, 12.9 mAP b+$\delta$. Furthermore, the high-quality V-JEPA 2.1 dense features enable the precise 2D detection of the next-active object bounding boxes, achieving 50.7 AP and surpassing DINOv3 ViT-7B in this category.
Qualitative results are shown in Figure [7](#S3.F7). V-JEPA 2.1 predicts plausible short-term interactions, with accurate bounding box localization, robust understanding of object categories, and plausible inference of the user next action intentions.

<a id="section-3-2"></a>

### 3.2 Action Anticipation

Action anticipation consists in predicting the future action given a contextual video clip leading up to some time before the action. Using the Epic-Kitchens-100 (EK100) benchmark (Damen et al., 2022), we show that V-JEPA 2.1 outperforms the action anticipation performance of V-JEPA 2, and sets a new state-of-the-art for the task.

##### Task.

The EK100 dataset is comprised of 100 hours of cooking activities recorded from an egocentric perspective across 45 kitchen environments. Each video in EK100 is annotated with action segments, which include a start timestamp, an end timestamp, and an action label. There are 3,568 unique action labels, each consisting of a verb and a noun category, with a total of 97 verb categories and 300 noun categories. The EK100 action anticipation task involves predicting noun, verb, and action (i.e., predicting verb and noun jointly) from a video clip, referred to as context, that occurs before the start timestamp of an action segment.
The interval between the end of the context and the beginning of the action segment is the anticipation time, which is set to 1 second by default. Given that different future actions may be possible from a given context, mean-class recall-at-5 is used as the metric to measure performance (Damen et al., 2022).

##### Evaluation protocol.

We employ the same protocol as V-JEPA 2 and use an attentive probe trained on top of the frozen V-JEPA 2.1 encoder and predictor to anticipate future actions. Specifically, we sample a video clip that ends 1 second before an action starts. This video context is fed to the encoder. The predictor takes the encoder representation, along with the mask tokens corresponding to the frame 1 second into the future, and predicts the representation of the future video frame. The outputs of the predictor and encoder are concatenated along the token dimension and fed to an attentive probe with a similar architecture to those used in our probe-based video classification protocol, with the difference being that the anticipation probe’s final cross-attention layer learns three query tokens (as opposed to one), and each query output is fed to a different linear classifier to predict the action category, the verb category, and the noun category respectively. A focal loss (Lin et al., 2017b) is applied to each classifier independently and then summed before back-propagating through the shared attention blocks of the probe.

<a id="table-5"></a>

> Table 5: Action Anticipation on EK100. Comparison with the state-of-the-art on the EK100 Action Anticipation benchmark. We report mean-class recall-at-5 for verb, noun and action on the validation set of EK100. V-JEPA 2.1 offers comparable performance to V-JEPA 2 for the ViT-g 1B model, but shows improved performance for the ViT-G 2B model, setting a new state-of-the-art for the task.

| Method                               | Param. | Action Anticipation |      |        |
| ------------------------------------ | ------ | ------------------- | ---- | ------ |
| Method                               | Param. | Action Anticipation |      |        |
| Method                               | Param. | Action Anticipation |      |        |
|                                      |        | Verb                | Noun | Action |
|                                      |        | Verb                | Noun | Action |
|                                      |        | Verb                | Noun | Action |
|                                      |        | Verb                | Noun | Action |
|                                      |        | Verb                | Noun | Action |
| InAViT (Roy et al., 2024)            | 160M   | 51.9                | 52.0 | 25.8   |
| InAViT (Roy et al., 2024)            | 160M   | 51.9                | 52.0 | 25.8   |
| InAViT (Roy et al., 2024)            | 160M   | 51.9                | 52.0 | 25.8   |
| InAViT (Roy et al., 2024)            | 160M   | 51.9                | 52.0 | 25.8   |
| InAViT (Roy et al., 2024)            | 160M   | 51.9                | 52.0 | 25.8   |
| Video-LLaMA (Zhang et al., 2023)     | 7B     | 52.9                | 52.0 | 26.0   |
| Video-LLaMA (Zhang et al., 2023)     | 7B     | 52.9                | 52.0 | 26.0   |
| Video-LLaMA (Zhang et al., 2023)     | 7B     | 52.9                | 52.0 | 26.0   |
| Video-LLaMA (Zhang et al., 2023)     | 7B     | 52.9                | 52.0 | 26.0   |
| Video-LLaMA (Zhang et al., 2023)     | 7B     | 52.9                | 52.0 | 26.0   |
| PlausiVL (Mittal et al., 2024)       | 8B     | 55.6                | 54.2 | 27.6   |
| PlausiVL (Mittal et al., 2024)       | 8B     | 55.6                | 54.2 | 27.6   |
| PlausiVL (Mittal et al., 2024)       | 8B     | 55.6                | 54.2 | 27.6   |
| PlausiVL (Mittal et al., 2024)       | 8B     | 55.6                | 54.2 | 27.6   |
| PlausiVL (Mittal et al., 2024)       | 8B     | 55.6                | 54.2 | 27.6   |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 1B     | 63.6                | 57.1 | 39.7   |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 1B     | 63.6                | 57.1 | 39.7   |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 1B     | 63.6                | 57.1 | 39.7   |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 1B     | 63.6                | 57.1 | 39.7   |
| V-JEPA 2 ViT-g (Assran et al., 2025) | 1B     | 63.6                | 57.1 | 39.7   |
| V-JEPA 2.1 ViT-g                     | 1B     | 63.6                | 56.2 | 38.4   |
| V-JEPA 2.1 ViT-g                     | 1B     | 63.6                | 56.2 | 38.4   |
| V-JEPA 2.1 ViT-g                     | 1B     | 63.6                | 56.2 | 38.4   |
| V-JEPA 2.1 ViT-g                     | 1B     | 63.6                | 56.2 | 38.4   |
| V-JEPA 2.1 ViT-g                     | 1B     | 63.6                | 56.2 | 38.4   |
| V-JEPA 2.1 ViT-G                     | 2B     | 64.3                | 59.9 | 40.8   |
| V-JEPA 2.1 ViT-G                     | 2B     | 64.3                | 59.9 | 40.8   |
| V-JEPA 2.1 ViT-G                     | 2B     | 64.3                | 59.9 | 40.8   |
| V-JEPA 2.1 ViT-G                     | 2B     | 64.3                | 59.9 | 40.8   |
| V-JEPA 2.1 ViT-G                     | 2B     | 64.3                | 59.9 | 40.8   |

##### Results.

Table [5](#S3.T5) summarizes the results on the validation set of the EK100 action anticipation benchmark. We compare V-JEPA 2.1 ViT-g 1B and ViT-G 2B encoders with V-JEPA 2 ViT-g 1B encoder. Both leverage 32 frames with 8 frames per second at resolution 384 × 384 as video context. V-JEPA 2.1 is comparable to V-JEPA 2 on the same 1B model size, but show scaling of the performance to the 2B models size, setting a new absolute state-of-the-art performance at 40.8 Action Recall@5, corresponding to a $+2.8\%$ improvement.

<a id="section-3-3"></a>

### 3.3 Robotic Arm Planning

Next, we evaluate V-JEPA 2.1 for robot manipulation.
To that end, we train a frame-causal action-conditioned predictor, following the protocol of Assran et al. (2025).
In particular, we use the public codebase from Assran et al. (2025) and modify it to compute features using our V-JEPA 2.1 video encoder; the predictor is an identical 24-layer transformer network containing approximately 300M parameters, and is trained on the Droid raw dataset (Khazatsky et al., 2024) using both a teacher-forcing and two-step rollout loss.
The model is then deployed in our lab, zero-shot, on a table-top Franka Panda robot arm with a parallel-jaw gripper, and evaluated on reach, grasp, and pick-and-place tasks with visual goal specification via model-predictive control.
We use the same exact task configuration files provided in Assran et al. (2025), and similar planning hyper-parameters.

<a id="table-6"></a>

> Table 6: Planning Performance. Comparing closed-loop robot manipulation of a cup using MPC with VJEPA 2 versus VJEPA 2.1. In both cases we leverage the cross-entropy method (Rubinstein, 1997) for optimizing the sequence of actions using a single A100 GPU. For each robot skill, we evaluate each model across 10 tasks and average the results. The improved depth understanding and dense features of VJEPA 2.1 lead to a 20% improvement in the success rate of Grasp. Moreover, qualitatively, we find that any failures on Pick-and-Place and Grasp are a result of poor planning over gripper actions, as opposed to failures in spatial understanding (e.g., closing the gripper too soon, such that you cannot grasp the object, or slightly opening the gripper while in transit leading to the object being dropped.

|                               | Planning Details |       |         |        |       |       |              |
| ----------------------------- | ---------------- | ----- | ------- | ------ | ----- | ----- | ------------ |
|                               | Planning Details |       |         |        |       |       |              |
|                               | Planning Details |       |         |        |       |       |              |
|                               | Planning Details |       |         |        |       |       |              |
|                               | Planning Details |       |         |        |       |       |              |
| Method                        | #Samples         | Iter. | Horizon | Time   | Reach | Grasp | Pick-&-Place |
| Method                        | #Samples         | Iter. | Horizon | Time   | Reach | Grasp | Pick-&-Place |
| Method                        | #Samples         | Iter. | Horizon | Time   | Reach | Grasp | Pick-&-Place |
| Method                        | #Samples         | Iter. | Horizon | Time   | Reach | Grasp | Pick-&-Place |
| Method                        | #Samples         | Iter. | Horizon | Time   | Reach | Grasp | Pick-&-Place |
| Method                        | #Samples         | Iter. | Horizon | Time   | Reach | Grasp | Pick-&-Place |
| Method                        | #Samples         | Iter. | Horizon | Time   | Reach | Grasp | Pick-&-Place |
| Method                        | #Samples         | Iter. | Horizon | Time   | Reach | Grasp | Pick-&-Place |
| VJEPA 2 (Assran et al., 2025) | 800              | 10    | 1       | 3 sec. | 100%  | 60%   | 80%          |
| VJEPA 2 (Assran et al., 2025) | 800              | 10    | 1       | 3 sec. | 100%  | 60%   | 80%          |
| VJEPA 2 (Assran et al., 2025) | 800              | 10    | 1       | 3 sec. | 100%  | 60%   | 80%          |
| VJEPA 2 (Assran et al., 2025) | 800              | 10    | 1       | 3 sec. | 100%  | 60%   | 80%          |
| VJEPA 2 (Assran et al., 2025) | 800              | 10    | 1       | 3 sec. | 100%  | 60%   | 80%          |
| VJEPA 2 (Assran et al., 2025) | 800              | 10    | 1       | 3 sec. | 100%  | 60%   | 80%          |
| VJEPA 2 (Assran et al., 2025) | 800              | 10    | 1       | 3 sec. | 100%  | 60%   | 80%          |
| VJEPA 2 (Assran et al., 2025) | 800              | 10    | 1       | 3 sec. | 100%  | 60%   | 80%          |
| VJEPA 2.1 (ours)              | 800              | 10    | 1       | 3 sec. | 100%  | 70%   | 80%          |
| VJEPA 2.1 (ours)              | 800              | 10    | 1       | 3 sec. | 100%  | 70%   | 80%          |
| VJEPA 2.1 (ours)              | 800              | 10    | 1       | 3 sec. | 100%  | 70%   | 80%          |
| VJEPA 2.1 (ours)              | 800              | 10    | 1       | 3 sec. | 100%  | 70%   | 80%          |
| VJEPA 2.1 (ours)              | 800              | 10    | 1       | 3 sec. | 100%  | 70%   | 80%          |
| VJEPA 2.1 (ours)              | 800              | 10    | 1       | 3 sec. | 100%  | 70%   | 80%          |
| VJEPA 2.1 (ours)              | 800              | 10    | 1       | 3 sec. | 100%  | 70%   | 80%          |
| VJEPA 2.1 (ours)              | 800              | 10    | 1       | 3 sec. | 100%  | 70%   | 80%          |
| 300                           | 15               | 8     | 14 sec. | 100%   | 80%   | 80%   |              |
| 300                           | 15               | 8     | 14 sec. | 100%   | 80%   | 80%   |              |
| 300                           | 15               | 8     | 14 sec. | 100%   | 80%   | 80%   |              |
| 300                           | 15               | 8     | 14 sec. | 100%   | 80%   | 80%   |              |
| 300                           | 15               | 8     | 14 sec. | 100%   | 80%   | 80%   |              |
| 300                           | 15               | 8     | 14 sec. | 100%   | 80%   | 80%   |              |
| 300                           | 15               | 8     | 14 sec. | 100%   | 80%   | 80%   |              |

Success rates are reported in Table [6](#S3.T6).
VJEPA 2.1 exhibits an improved depth understanding, leading to a 10% improvement in the success rate of Grasp compared to VJEPA 2 (cf. Figure [8](#S3.F8)).
Moreover, we find that the VJEPA 2.1 model unlocks the benefit of planning with slightly longer rollouts, perhaps due to the improvement in dense features afforded by our model.
In particular, by reducing the number of CEM samples and planning over 8 steps, we observe an additional improvement in the success rate on Grasp.
By contrast, we actually observe a degradation in the success rate of VJEPA 2 when planning over longer horizons.
Qualitatively, we further observe that task failures using the VJEPA 2.1 model on Pick-and-Place and Grasp are a result of poor planning over gripper actions, as opposed to failures in spatial understanding; e.g., closing the gripper too soon such that you cannot grasp the object, or slightly opening the gripper while in transit leading to the object being dropped.

<a id="figure-8"></a>

![architecture_vjepa2_1](images/architecture_vjepa2_1.jpg)

> Figure 8: Zero-shot evaluation of VJEPA 2 and VJEPA 2.1 models on a table-top Franka Panda robot arm with a parallel-jaw gripper, demonstrating Grasp of a cup using visual goal specification via model-predictive control. VJEPA 2.1 features better encode depth information, leading to an improvement in robot manipulation when grasping the cup involves reasoning over actions along the depth axis of the camera.

<a id="section-3-4"></a>

### 3.4 Navigation Planning

<a id="figure-9"></a>

![v2_to_25](images/v2_to_25.png)

> Figure 9: Planning Navigation Trajectories in Latent Space. V-JEPA 2.1 enables $10\times$ faster and more accurate navigation planning compared to (Bar et al., 2025). We show PCA visualizations of 8 denoising steps of the planned latent trajectory between a start frame and a goal frame.

Next, we evaluate the utility of V-JEPA 2.1 representations for short-term robotic navigation. Specifically, given an agent’s most recent observation and a goal location specified by an image, we predict a 2-second navigation trajectory toward the goal. We adopt the navigation planning setup of NWM (Bar et al., 2025) and train a latent world model on top of the V-JEPA 2.1 representations. We find that V-JEPA 2.1 enables more accurate planning while achieving $10\times$ faster planning speed than the previously used SD-VAE (Rombach et al., 2022). Results are reported in Table [7](#S3.T7), with qualitative examples shown in Figure [9](#S3.F9).

We train a Conditional Diffusion Transformer (CDiT) on top of the V-JEPA 2.1 representations, similarly to NWM. Our initial experiments indicate that directly training a diffusion model in the high-dimensional embedding space of the V-JEPA 2.1 is challenging: because the representations are high-dimensional (at least $80\times$ larger than those of an SD-VAE), injecting noise in arbitrary directions can easily push samples off the data manifold. To improve robustness, we introduce two modifications. First, we train the model to predict a clean representation rather than noise (Li and He, 2025). Second, we use DDIM sampling (Song et al., 2020), which is less stochastic than DDPM (Ho et al., 2020) and empirically improves stability.

For planning, given an initial context embedding and a goal, we use the Cross-Entropy Method to sample $N=480$ candidate trajectories of length $2$ seconds at $4$ FPS. We select the best candidate by simulating it in the world model and choosing the trajectory that minimizes the distance to the goal embedding. To simplify the search, we plan in a reduced 3-DoF action space (translation and yaw rotation). With V-JEPA 2.1, we require only $8$ denoising steps, compared to the optimal SD-VAE setting which requires at least $128$ steps. This yields lower Absolute Trajectory Error (ATE) and Relative Trajectory Error (RTE) on the validation set while reducing planning time by $10\times$.

<a id="table-7"></a>

> Table 7: Open Loop Navigation Planning. We finetune V-JEPA 2.1 on robot navigation datasets and compare the open-loop planning performance to NWM. Reporting the average planning time (seconds), normalized Average Trajectory Error (ATE) and Relative Trajectory Error (RTE). V-JEPA 2.1 representation enables $10\times$ speed-up without sacrificing performance.

| Model                  | Time        | Recon | Tartan Drive | Scand | Sacson | Average |       |       |       |       |       |
| ---------------------- | ----------- | ----- | ------------ | ----- | ------ | ------- | ----- | ----- | ----- | ----- | ----- |
| Model                  | Time        | Recon | Tartan Drive | Scand | Sacson | Average |       |       |       |       |       |
| Model                  | Time        | Recon | Tartan Drive | Scand | Sacson | Average |       |       |       |       |       |
| Model                  | Time        | Recon | Tartan Drive | Scand | Sacson | Average |       |       |       |       |       |
| Model                  | Time        | Recon | Tartan Drive | Scand | Sacson | Average |       |       |       |       |       |
| Model                  | Time        | Recon | Tartan Drive | Scand | Sacson | Average |       |       |       |       |       |
| Model                  | Time        | Recon | Tartan Drive | Scand | Sacson | Average |       |       |       |       |       |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
|                        |             | ATE   | RTE          | ATE   | RTE    | ATE     | RTE   | ATE   | RTE   | ATE   | RTE   |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| NWM (Bar et al., 2025) | $103.2$ (s) | 1.146 | 0.339        | 5.831 | 1.219  | 1.113   | 0.297 | 4.037 | 0.928 | 3.032 | 0.696 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-g       | 10.6 (s)    | 1.146 | 0.338        | 5.758 | 1.200  | 1.094   | 0.299 | 3.904 | 0.921 | 2.975 | 0.690 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |
| V-JEPA 2.1 ViT-G       | 10.6 (s)    | 1.179 | 0.340        | 5.687 | 1.187  | 1.038   | 0.285 | 4.054 | 0.938 | 2.990 | 0.688 |

<a id="table-8"></a>

> Table 8: Performance on dense visual tasks. We report the Root Mean Squared Error (RMSE) for depth estimation (NYUv2, KITTI), mean Intersection-over-Union (mIoU) for semantic segmentation (ADE20K, Cityscapes, VOC12), and the $\mathcal{J}\&\mathcal{F}$-Mean for video object segmentation (DAVIS, YouTube-VOS). Following Siméoni et al. (2025), ADE20K and VOC12 are evaluated at an input resolution of $448\times 448$ for models with patch size 14 and $512\times 512$ for those with patch size 16. Cityscapes, NYUv2, and KITTI use their default evaluation resolutions. For DAVIS and YouTube-VOS, we evaluate with the shorter image side set to 480 px (patch size 16) or 420 px (patch size 14). V-JEPA 2.1 VIT G demonstrates strong performance on dense vision tasks. Notably, it achieves state-of-art performances on NYUv2 depth estimation, outperforming a DINOv3 backbone with 7 billion parameters.

| Method                                | Param.            | Depth  | Segmentation | VOS  |         |          |      |      |
| ------------------------------------- | ----------------- | ------ | ------------ | ---- | ------- | -------- | ---- | ---- |
| Method                                | Param.            | Depth  | Segmentation | VOS  |         |          |      |      |
| Method                                | Param.            | Depth  | Segmentation | VOS  |         |          |      |      |
| Method                                | Param.            | Depth  | Segmentation | VOS  |         |          |      |      |
| Method                                | Param.            | Depth  | Segmentation | VOS  |         |          |      |      |
| NYUv2$\downarrow$                     | KITTI$\downarrow$ | ADE20k | Citysc.      | VOC  | DAVIS-S | YT VOS-S |      |      |
| NYUv2$\downarrow$                     | KITTI$\downarrow$ | ADE20k | Citysc.      | VOC  | DAVIS-S | YT VOS-S |      |      |
| NYUv2$\downarrow$                     | KITTI$\downarrow$ | ADE20k | Citysc.      | VOC  | DAVIS-S | YT VOS-S |      |      |
| NYUv2$\downarrow$                     | KITTI$\downarrow$ | ADE20k | Citysc.      | VOC  | DAVIS-S | YT VOS-S |      |      |
| NYUv2$\downarrow$                     | KITTI$\downarrow$ | ADE20k | Citysc.      | VOC  | DAVIS-S | YT VOS-S |      |      |
| NYUv2$\downarrow$                     | KITTI$\downarrow$ | ADE20k | Citysc.      | VOC  | DAVIS-S | YT VOS-S |      |      |
| NYUv2$\downarrow$                     | KITTI$\downarrow$ | ADE20k | Citysc.      | VOC  | DAVIS-S | YT VOS-S |      |      |
| 7B models                             |                   |        |              |      |         |          |      |      |
| Web-DINO (Fan et al., 2025)           | 7B/14             | 0.466  | 3.158        | 42.7 | 68.3    | 76.1     | 57.2 | 43.9 |
| Web-DINO (Fan et al., 2025)           | 7B/14             | 0.466  | 3.158        | 42.7 | 68.3    | 76.1     | 57.2 | 43.9 |
| Web-DINO (Fan et al., 2025)           | 7B/14             | 0.466  | 3.158        | 42.7 | 68.3    | 76.1     | 57.2 | 43.9 |
| Web-DINO (Fan et al., 2025)           | 7B/14             | 0.466  | 3.158        | 42.7 | 68.3    | 76.1     | 57.2 | 43.9 |
| Web-DINO (Fan et al., 2025)           | 7B/14             | 0.466  | 3.158        | 42.7 | 68.3    | 76.1     | 57.2 | 43.9 |
| Web-DINO (Fan et al., 2025)           | 7B/14             | 0.466  | 3.158        | 42.7 | 68.3    | 76.1     | 57.2 | 43.9 |
| Web-DINO (Fan et al., 2025)           | 7B/14             | 0.466  | 3.158        | 42.7 | 68.3    | 76.1     | 57.2 | 43.9 |
| Web-DINO (Fan et al., 2025)           | 7B/14             | 0.466  | 3.158        | 42.7 | 68.3    | 76.1     | 57.2 | 43.9 |
| Web-DINO (Fan et al., 2025)           | 7B/14             | 0.466  | 3.158        | 42.7 | 68.3    | 76.1     | 57.2 | 43.9 |
| DINOv3 (Siméoni et al., 2025)         | 7B/16             | 0.309  | 2.346        | 55.9 | 81.1    | 86.6     | 71.1 | 74.1 |
| DINOv3 (Siméoni et al., 2025)         | 7B/16             | 0.309  | 2.346        | 55.9 | 81.1    | 86.6     | 71.1 | 74.1 |
| DINOv3 (Siméoni et al., 2025)         | 7B/16             | 0.309  | 2.346        | 55.9 | 81.1    | 86.6     | 71.1 | 74.1 |
| DINOv3 (Siméoni et al., 2025)         | 7B/16             | 0.309  | 2.346        | 55.9 | 81.1    | 86.6     | 71.1 | 74.1 |
| DINOv3 (Siméoni et al., 2025)         | 7B/16             | 0.309  | 2.346        | 55.9 | 81.1    | 86.6     | 71.1 | 74.1 |
| DINOv3 (Siméoni et al., 2025)         | 7B/16             | 0.309  | 2.346        | 55.9 | 81.1    | 86.6     | 71.1 | 74.1 |
| DINOv3 (Siméoni et al., 2025)         | 7B/16             | 0.309  | 2.346        | 55.9 | 81.1    | 86.6     | 71.1 | 74.1 |
| DINOv3 (Siméoni et al., 2025)         | 7B/16             | 0.309  | 2.346        | 55.9 | 81.1    | 86.6     | 71.1 | 74.1 |
| DINOv3 (Siméoni et al., 2025)         | 7B/16             | 0.309  | 2.346        | 55.9 | 81.1    | 86.6     | 71.1 | 74.1 |
| Models less than 2B parameters        |                   |        |              |      |         |          |      |      |
| PEcore (Bolya et al., 2025)           | 2B/14             | 0.590  | 4.119        | 38.9 | 61.1    | 69.2     | 48.2 | 34.7 |
| PEcore (Bolya et al., 2025)           | 2B/14             | 0.590  | 4.119        | 38.9 | 61.1    | 69.2     | 48.2 | 34.7 |
| PEcore (Bolya et al., 2025)           | 2B/14             | 0.590  | 4.119        | 38.9 | 61.1    | 69.2     | 48.2 | 34.7 |
| PEcore (Bolya et al., 2025)           | 2B/14             | 0.590  | 4.119        | 38.9 | 61.1    | 69.2     | 48.2 | 34.7 |
| PEcore (Bolya et al., 2025)           | 2B/14             | 0.590  | 4.119        | 38.9 | 61.1    | 69.2     | 48.2 | 34.7 |
| PEcore (Bolya et al., 2025)           | 2B/14             | 0.590  | 4.119        | 38.9 | 61.1    | 69.2     | 48.2 | 34.7 |
| PEcore (Bolya et al., 2025)           | 2B/14             | 0.590  | 4.119        | 38.9 | 61.1    | 69.2     | 48.2 | 34.7 |
| PEcore (Bolya et al., 2025)           | 2B/14             | 0.590  | 4.119        | 38.9 | 61.1    | 69.2     | 48.2 | 34.7 |
| PEcore (Bolya et al., 2025)           | 2B/14             | 0.590  | 4.119        | 38.9 | 61.1    | 69.2     | 48.2 | 34.7 |
| PEspatial (Bolya et al., 2025)        | 2B/14             | 0.362  | 3.082        | 49.3 | 73.2    | 82.7     | 68.4 | 68.5 |
| PEspatial (Bolya et al., 2025)        | 2B/14             | 0.362  | 3.082        | 49.3 | 73.2    | 82.7     | 68.4 | 68.5 |
| PEspatial (Bolya et al., 2025)        | 2B/14             | 0.362  | 3.082        | 49.3 | 73.2    | 82.7     | 68.4 | 68.5 |
| PEspatial (Bolya et al., 2025)        | 2B/14             | 0.362  | 3.082        | 49.3 | 73.2    | 82.7     | 68.4 | 68.5 |
| PEspatial (Bolya et al., 2025)        | 2B/14             | 0.362  | 3.082        | 49.3 | 73.2    | 82.7     | 68.4 | 68.5 |
| PEspatial (Bolya et al., 2025)        | 2B/14             | 0.362  | 3.082        | 49.3 | 73.2    | 82.7     | 68.4 | 68.5 |
| PEspatial (Bolya et al., 2025)        | 2B/14             | 0.362  | 3.082        | 49.3 | 73.2    | 82.7     | 68.4 | 68.5 |
| PEspatial (Bolya et al., 2025)        | 2B/14             | 0.362  | 3.082        | 49.3 | 73.2    | 82.7     | 68.4 | 68.5 |
| PEspatial (Bolya et al., 2025)        | 2B/14             | 0.362  | 3.082        | 49.3 | 73.2    | 82.7     | 68.4 | 68.5 |
| AM-RADIOv2.5 (Ranzinger et al., 2024) | 1B/14             | 0.340  | 2.918        | 53.0 | 78.4    | 85.4     | 66.5 | 70.1 |
| AM-RADIOv2.5 (Ranzinger et al., 2024) | 1B/14             | 0.340  | 2.918        | 53.0 | 78.4    | 85.4     | 66.5 | 70.1 |
| AM-RADIOv2.5 (Ranzinger et al., 2024) | 1B/14             | 0.340  | 2.918        | 53.0 | 78.4    | 85.4     | 66.5 | 70.1 |
| AM-RADIOv2.5 (Ranzinger et al., 2024) | 1B/14             | 0.340  | 2.918        | 53.0 | 78.4    | 85.4     | 66.5 | 70.1 |
| AM-RADIOv2.5 (Ranzinger et al., 2024) | 1B/14             | 0.340  | 2.918        | 53.0 | 78.4    | 85.4     | 66.5 | 70.1 |
| AM-RADIOv2.5 (Ranzinger et al., 2024) | 1B/14             | 0.340  | 2.918        | 53.0 | 78.4    | 85.4     | 66.5 | 70.1 |
| AM-RADIOv2.5 (Ranzinger et al., 2024) | 1B/14             | 0.340  | 2.918        | 53.0 | 78.4    | 85.4     | 66.5 | 70.1 |
| AM-RADIOv2.5 (Ranzinger et al., 2024) | 1B/14             | 0.340  | 2.918        | 53.0 | 78.4    | 85.4     | 66.5 | 70.1 |
| AM-RADIOv2.5 (Ranzinger et al., 2024) | 1B/14             | 0.340  | 2.918        | 53.0 | 78.4    | 85.4     | 66.5 | 70.1 |
| InternVideo2-1B (Wang et al., 2024b)  | 1B/14             | 0.471  | 4.739        | 28.4 | 35.6    | 65.2     | 50.6 | 51.2 |
| InternVideo2-1B (Wang et al., 2024b)  | 1B/14             | 0.471  | 4.739        | 28.4 | 35.6    | 65.2     | 50.6 | 51.2 |
| InternVideo2-1B (Wang et al., 2024b)  | 1B/14             | 0.471  | 4.739        | 28.4 | 35.6    | 65.2     | 50.6 | 51.2 |
| InternVideo2-1B (Wang et al., 2024b)  | 1B/14             | 0.471  | 4.739        | 28.4 | 35.6    | 65.2     | 50.6 | 51.2 |
| InternVideo2-1B (Wang et al., 2024b)  | 1B/14             | 0.471  | 4.739        | 28.4 | 35.6    | 65.2     | 50.6 | 51.2 |
| InternVideo2-1B (Wang et al., 2024b)  | 1B/14             | 0.471  | 4.739        | 28.4 | 35.6    | 65.2     | 50.6 | 51.2 |
| InternVideo2-1B (Wang et al., 2024b)  | 1B/14             | 0.471  | 4.739        | 28.4 | 35.6    | 65.2     | 50.6 | 51.2 |
| InternVideo2-1B (Wang et al., 2024b)  | 1B/14             | 0.471  | 4.739        | 28.4 | 35.6    | 65.2     | 50.6 | 51.2 |
| InternVideo2-1B (Wang et al., 2024b)  | 1B/14             | 0.471  | 4.739        | 28.4 | 35.6    | 65.2     | 50.6 | 51.2 |
| SigLIP 2 (Tschannen et al., 2025)     | 1B/16             | 0.494  | 3.273        | 42.7 | 64.8    | 72.7     | 56.1 | 52.0 |
| SigLIP 2 (Tschannen et al., 2025)     | 1B/16             | 0.494  | 3.273        | 42.7 | 64.8    | 72.7     | 56.1 | 52.0 |
| SigLIP 2 (Tschannen et al., 2025)     | 1B/16             | 0.494  | 3.273        | 42.7 | 64.8    | 72.7     | 56.1 | 52.0 |
| SigLIP 2 (Tschannen et al., 2025)     | 1B/16             | 0.494  | 3.273        | 42.7 | 64.8    | 72.7     | 56.1 | 52.0 |
| SigLIP 2 (Tschannen et al., 2025)     | 1B/16             | 0.494  | 3.273        | 42.7 | 64.8    | 72.7     | 56.1 | 52.0 |
| SigLIP 2 (Tschannen et al., 2025)     | 1B/16             | 0.494  | 3.273        | 42.7 | 64.8    | 72.7     | 56.1 | 52.0 |
| SigLIP 2 (Tschannen et al., 2025)     | 1B/16             | 0.494  | 3.273        | 42.7 | 64.8    | 72.7     | 56.1 | 52.0 |
| SigLIP 2 (Tschannen et al., 2025)     | 1B/16             | 0.494  | 3.273        | 42.7 | 64.8    | 72.7     | 56.1 | 52.0 |
| SigLIP 2 (Tschannen et al., 2025)     | 1B/16             | 0.494  | 3.273        | 42.7 | 64.8    | 72.7     | 56.1 | 52.0 |
| DINOv2 (Oquab et al., 2023)           | 1B/14             | 0.372  | 2.624        | 49.5 | 75.6    | 83.1     | 63.9 | 65.6 |
| DINOv2 (Oquab et al., 2023)           | 1B/14             | 0.372  | 2.624        | 49.5 | 75.6    | 83.1     | 63.9 | 65.6 |
| DINOv2 (Oquab et al., 2023)           | 1B/14             | 0.372  | 2.624        | 49.5 | 75.6    | 83.1     | 63.9 | 65.6 |
| DINOv2 (Oquab et al., 2023)           | 1B/14             | 0.372  | 2.624        | 49.5 | 75.6    | 83.1     | 63.9 | 65.6 |
| DINOv2 (Oquab et al., 2023)           | 1B/14             | 0.372  | 2.624        | 49.5 | 75.6    | 83.1     | 63.9 | 65.6 |
| DINOv2 (Oquab et al., 2023)           | 1B/14             | 0.372  | 2.624        | 49.5 | 75.6    | 83.1     | 63.9 | 65.6 |
| DINOv2 (Oquab et al., 2023)           | 1B/14             | 0.372  | 2.624        | 49.5 | 75.6    | 83.1     | 63.9 | 65.6 |
| DINOv2 (Oquab et al., 2023)           | 1B/14             | 0.372  | 2.624        | 49.5 | 75.6    | 83.1     | 63.9 | 65.6 |
| DINOv2 (Oquab et al., 2023)           | 1B/14             | 0.372  | 2.624        | 49.5 | 75.6    | 83.1     | 63.9 | 65.6 |
| DINOv3 ViT-H+ (Siméoni et al., 2025)  | 0.8B/16           | 0.352  | 2.635        | 54.8 | 79.5    | 85.8     | 71.1 | 74.0 |
| DINOv3 ViT-H+ (Siméoni et al., 2025)  | 0.8B/16           | 0.352  | 2.635        | 54.8 | 79.5    | 85.8     | 71.1 | 74.0 |
| DINOv3 ViT-H+ (Siméoni et al., 2025)  | 0.8B/16           | 0.352  | 2.635        | 54.8 | 79.5    | 85.8     | 71.1 | 74.0 |
| DINOv3 ViT-H+ (Siméoni et al., 2025)  | 0.8B/16           | 0.352  | 2.635        | 54.8 | 79.5    | 85.8     | 71.1 | 74.0 |
| DINOv3 ViT-H+ (Siméoni et al., 2025)  | 0.8B/16           | 0.352  | 2.635        | 54.8 | 79.5    | 85.8     | 71.1 | 74.0 |
| DINOv3 ViT-H+ (Siméoni et al., 2025)  | 0.8B/16           | 0.352  | 2.635        | 54.8 | 79.5    | 85.8     | 71.1 | 74.0 |
| DINOv3 ViT-H+ (Siméoni et al., 2025)  | 0.8B/16           | 0.352  | 2.635        | 54.8 | 79.5    | 85.8     | 71.1 | 74.0 |
| DINOv3 ViT-H+ (Siméoni et al., 2025)  | 0.8B/16           | 0.352  | 2.635        | 54.8 | 79.5    | 85.8     | 71.1 | 74.0 |
| DINOv3 ViT-H+ (Siméoni et al., 2025)  | 0.8B/16           | 0.352  | 2.635        | 54.8 | 79.5    | 85.8     | 71.1 | 74.0 |
| V-JEPA2 ViT-g (Assran et al., 2025)   | 1B/16             | 0.642  | 4.650        | 24.4 | 45.9    | 63.9     | 52.5 | 53.7 |
| V-JEPA2 ViT-g (Assran et al., 2025)   | 1B/16             | 0.642  | 4.650        | 24.4 | 45.9    | 63.9     | 52.5 | 53.7 |
| V-JEPA2 ViT-g (Assran et al., 2025)   | 1B/16             | 0.642  | 4.650        | 24.4 | 45.9    | 63.9     | 52.5 | 53.7 |
| V-JEPA2 ViT-g (Assran et al., 2025)   | 1B/16             | 0.642  | 4.650        | 24.4 | 45.9    | 63.9     | 52.5 | 53.7 |
| V-JEPA2 ViT-g (Assran et al., 2025)   | 1B/16             | 0.642  | 4.650        | 24.4 | 45.9    | 63.9     | 52.5 | 53.7 |
| V-JEPA2 ViT-g (Assran et al., 2025)   | 1B/16             | 0.642  | 4.650        | 24.4 | 45.9    | 63.9     | 52.5 | 53.7 |
| V-JEPA2 ViT-g (Assran et al., 2025)   | 1B/16             | 0.642  | 4.650        | 24.4 | 45.9    | 63.9     | 52.5 | 53.7 |
| V-JEPA2 ViT-g (Assran et al., 2025)   | 1B/16             | 0.642  | 4.650        | 24.4 | 45.9    | 63.9     | 52.5 | 53.7 |
| V-JEPA2 ViT-g (Assran et al., 2025)   | 1B/16             | 0.642  | 4.650        | 24.4 | 45.9    | 63.9     | 52.5 | 53.7 |
| V-JEPA 2.1 ViT-g                      | 1B/16             | 0.350  | 2.601        | 47.8 | 71.8    | 84.7     | 68.1 | 72.3 |
| V-JEPA 2.1 ViT-g                      | 1B/16             | 0.350  | 2.601        | 47.8 | 71.8    | 84.7     | 68.1 | 72.3 |
| V-JEPA 2.1 ViT-g                      | 1B/16             | 0.350  | 2.601        | 47.8 | 71.8    | 84.7     | 68.1 | 72.3 |
| V-JEPA 2.1 ViT-g                      | 1B/16             | 0.350  | 2.601        | 47.8 | 71.8    | 84.7     | 68.1 | 72.3 |
| V-JEPA 2.1 ViT-g                      | 1B/16             | 0.350  | 2.601        | 47.8 | 71.8    | 84.7     | 68.1 | 72.3 |
| V-JEPA 2.1 ViT-g                      | 1B/16             | 0.350  | 2.601        | 47.8 | 71.8    | 84.7     | 68.1 | 72.3 |
| V-JEPA 2.1 ViT-g                      | 1B/16             | 0.350  | 2.601        | 47.8 | 71.8    | 84.7     | 68.1 | 72.3 |
| V-JEPA 2.1 ViT-g                      | 1B/16             | 0.350  | 2.601        | 47.8 | 71.8    | 84.7     | 68.1 | 72.3 |
| V-JEPA 2.1 ViT-g                      | 1B/16             | 0.350  | 2.601        | 47.8 | 71.8    | 84.7     | 68.1 | 72.3 |
| V-JEPA 2.1 ViT-G                      | 2B/16             | 0.307  | 2.461        | 47.9 | 73.5    | 85.0     | 69.0 | 72.7 |
| V-JEPA 2.1 ViT-G                      | 2B/16             | 0.307  | 2.461        | 47.9 | 73.5    | 85.0     | 69.0 | 72.7 |
| V-JEPA 2.1 ViT-G                      | 2B/16             | 0.307  | 2.461        | 47.9 | 73.5    | 85.0     | 69.0 | 72.7 |
| V-JEPA 2.1 ViT-G                      | 2B/16             | 0.307  | 2.461        | 47.9 | 73.5    | 85.0     | 69.0 | 72.7 |
| V-JEPA 2.1 ViT-G                      | 2B/16             | 0.307  | 2.461        | 47.9 | 73.5    | 85.0     | 69.0 | 72.7 |
| V-JEPA 2.1 ViT-G                      | 2B/16             | 0.307  | 2.461        | 47.9 | 73.5    | 85.0     | 69.0 | 72.7 |
| V-JEPA 2.1 ViT-G                      | 2B/16             | 0.307  | 2.461        | 47.9 | 73.5    | 85.0     | 69.0 | 72.7 |
| V-JEPA 2.1 ViT-G                      | 2B/16             | 0.307  | 2.461        | 47.9 | 73.5    | 85.0     | 69.0 | 72.7 |
| V-JEPA 2.1 ViT-G                      | 2B/16             | 0.307  | 2.461        | 47.9 | 73.5    | 85.0     | 69.0 | 72.7 |

<a id="figure-10"></a>

![image_337](images/image_337.png)

> Figure 10: Depth estimation comparison on NYU and KITTI datasets. While V-JEPA 2 captures the overall scene geometry, its predictions lack local consistency and precise boundary structure. In contrast, our V-JEPA 2.1 produces sharper, more coherent, and fine-grained depth maps.

<a id="figure-11"></a>

![image_decoder_linear_lr_0_00150000_wd_0_01000000_110](images/image_decoder_linear_lr_0_00150000_wd_0_01000000_110.jpg)

> Figure 11: Semantic segmentation qualitative results in VOC12 and Cityscapes datasets. The previous version, V-JEPA 2, produced sparse semantic masks due to the presence noisy feature maps. However, V-JEPA 2.1 achieves competitive performance with state of the art methods such as DINOv3 ViT-H+.

<a id="section-3-5"></a>

### 3.5 Depth Estimation and Semantic Segmentation

We evaluate the quality of the learned representations on semantic segmentation and depth estimation, two tasks that require fine-grained understanding of the image spatial structure.

##### Task.

Semantic segmentation probes the model’s ability to capture category-level semantics and object boundaries. We evaluate our model on PASCAL VOC12 (Everingham et al., 2015), ADE20K (Zhou et al., 2017b), and Cityscapes (Cordts et al., 2016), reporting the mean Intersection over Union (mIoU). As in Siméoni et al. (2025), the input resolution of the images is adapted to 1024 patch tokens ($i.e.$, $512\times 512$ for patch size 16, $448\times 448$ for patch size 14).
On the other hand, depth estimation evaluates the model’s understanding of the scene’s geometric structure. For this task, we use the NYUv2 (Silberman et al., 2012a) and KITTI (Geiger et al., 2013b) benchmarks and report the Root Mean Squared Error (RMSE).

<a id="figure-12"></a>

![depth_vs_dino](images/depth_vs_dino.jpg)

> Figure 12: Qualitative comparative of V-JEPA 2.1 ViT-G vs DINOv3 ViT-H$+$. V-JEPA 2.1 captures fine-grained details (i.e the traffic light contour) and obtains better scale consistency. In the two rightmost columns, DINOv3 mislabel the depth of the green object on the bed, and the TV, and detect them closer to the camera than they are.

##### Evaluation protocol.

Following the protocol of DINOv3 (Siméoni et al., 2025), we train a dense linear projection on top of the frozen final-layer features of the V-JEPA 2.1 encoder using the image patchifier.
Importantly, we do not utilize intermediate layers from the encoder.
As V-JEPA 2.1 adopts a 3D RoPe for positional encoding, the frequencies are interpolated according to the image resolution.

##### Results.

Table [8](#S3.T8) summarizes the performance of V-JEPA 2.1 and other visual encoders on depth estimation and single-image semantic segmentation.
V-JEPA 2.1 ViT-G achieves state-of-the-art results on linear-probe monocular depth estimation, reaching 0.307 RMSE on NYUv2 and strong performance on KITTI with 2.461 RMSE, performing best across models that have less than 2 billion parameter.
On NYUv2, V-JEPA 2.1 surpasses prior image encoders, including DINOv3 ViT-7B (0.309 RMSE on NYU) and PEspatial-G (0.362 RMSE on NYU), and it represents a significant improvement over video encoders such as InternVideo2-1B (0.471 RMSE) and V-JEPA 2 (0.642 RMSE).
Figure [10](#S3.F10) provides a qualitative comparison of the depth maps predicted by V-JEPA 2 and V-JEPA 2.1. While V-JEPA 2 captures the overall scene geometry, the inconsistencies of its local features lead to noisy depth maps. In contrast, our novel V-JEPA 2.1 produces sharper and more coherent depth maps with well-defined object boundaries.
We also visualize a more detailed qualitative comparative with DINOv3 ViT-H+ in Figure [12](#S3.F12).

In semantic segmentation, V-JEPA 2.1 is also highly competitive with the state-of-the-art models, obtaining 85.0 mIoU on VOC12, 73.5 mIoU on Cityscapes and 47.9 mIoU on ADE20K. Compared with its previous version V-JEPA 2, the gains are remarkable across all datasets: +23.4 points in ADE20K, +27.6 on Cityscapes, and + 20.7 on VOC12; showing the benefits of explicitly supervising the context tokens and incorporating the multi-level predictor.

Performance on ADE20K and Cityscapes remains slightly behind the best image encoders. These datasets contain numerous object classes spanning large scale variations, with cluttered scene layouts that impose strict demands on fine-grained segmentation. We hypothesize that VisionMix contains comparatively fewer highly cluttered scenes, limiting exposure to the level of granularity required by such benchmarks.
Figure [11](#S3.F11) illustrates segmentation predictions on Cityscapes and VOC12. V-JEPA 2.1 yields detailed and spatially accurate masks, capturing multi-scale structures and fine object contours with high fidelity, showing competitive performance with state-of-the-art methods such as DINOv3 ViT-H+ (Siméoni et al., 2025).

<a id="section-3-6"></a>

### 3.6 Video Object Segmentation

We evaluate V-JEPA 2.1 on Video Object Segmentation (VOS) to assess the temporal consistency of its learned features.

<a id="figure-13"></a>

![gt_3](images/gt_3.jpg)

> Figure 13: Video Object Segmentation qualitative examples. Given the ground-truth object masks for the initial frame, we propagate the instance masks to subsequent frames based on patch similarity within the V-JEPA 2.1 embedding space. All videos are processed at a resolution where the shorter side is set to 480 pixels.

##### Task.

Video Object Segmentation consists in, given the ground-truth object mask in the first frame, propagating this mask accurately across all subsequent frames. This task evaluates the model’s ability to preserve long-range correspondences while remaining robust to camera motion, object deformation, and visual distractions.
We evaluate on DAVIS 2017 (Pont-Tuset et al., 2017) and YouTube-VOS (Xu et al., 2018) datasets, reporting the standard $\mathcal{J}\&\mathcal{F}$-mean metric (Perazzi et al., 2016) that jointly measures the region similarity and contour accuracy.

##### Evaluation protocol.

We adopt a non-parametric label propagation approach (Jabri et al., 2020) that matches local patch features across frames using cosine similarity in the embedding space. This procedure introduces no learnable parameters, making it a direct probe of the representation’s temporal stability.
Following Siméoni et al. (2025), input videos are resized to produce a consistent number of patch tokens (short side of 420 px for patch size 14, and 480 px for patch size 16).
On the training split of each dataset, we conduct a systematic search of the best hyper-parameters: maximum context length, neighborhood mask size, number of top-$K$ nearest neighbors, and the temperature parameter used in similarity computation. The best configuration in DAVIS-S (15 context frames, circle mask of size 12, top-5 neighbors and temperature = 0.2), was applied to all the validation sets.

##### Results.

V-JEPA 2.1 achieves 69.0 $\mathcal{J}\&\mathcal{F}$ on DAVIS-17 and 72.7 $\mathcal{J}\&\mathcal{F}$ on YouTube-VOS datasets, obtaining the second best performance and surpassing all prior encoders except DINOv3, which attains a slightly higher score.
These results highlight the temporal consistency of the V-JEPA 2.1 features, which enable stable object tracking despite significant appearance changes across frames.
Figure [13](#S3.F13) illustrates two qualitative examples: even under fast motion and substantial visual variations, V-JEPA 2.1 maintains consistent object segmentation masks throughout the sequence.

<a id="section-3-7"></a>

### 3.7 Video and Image Classification

<a id="table-9"></a>

> Table 9: Performance on global tasks. We report Top-1 classification accuracy on action recognition benchmarks (SSv2, Diving-48, and K400) and image classification (IN1K). Our protocol uses a resolution of $256\times 256$ by default, and $384\times 384$ for V-JEPA 2 ViT-g and V-JEPA 2.1; and uses $16\times 2\times 3$ inputs for SSv2 (16-frame clips, 2 temporal crops, 3 spatial crops), $16\times 8\times 3$ for K400, and $32\times 4\times 3$ for Diving-48. V-JEPA 2.1 VIT-G achieves state-of-art performance on the SSv2 action recognition asks while being competitive on appearance understanding tasks.

| Method                                           | Param. | Motion Understanding | Appearance Understanding |      |        |
| ------------------------------------------------ | ------ | -------------------- | ------------------------ | ---- | ------ |
| Method                                           | Param. | Motion Understanding | Appearance Understanding |      |        |
| Method                                           | Param. | Motion Understanding | Appearance Understanding |      |        |
| Method                                           | Param. | Motion Understanding | Appearance Understanding |      |        |
|                                                  |        | SSv2                 | Diving-48                | K400 | IN1K   |
|                                                  |        | SSv2                 | Diving-48                | K400 | IN1K   |
|                                                  |        | SSv2                 | Diving-48                | K400 | IN1K   |
|                                                  |        | SSv2                 | Diving-48                | K400 | IN1K   |
|                                                  |        | SSv2                 | Diving-48                | K400 | IN1K   |
|                                                  |        | SSv2                 | Diving-48                | K400 | IN1K   |
| Results Reported in the Literature               |        |                      |                          |      |        |
| VideoMAEv2 (Wang et al., 2023)                   | 1B     | 56.1                 | –                        | 82.8 | 71.4   |
| VideoMAEv2 (Wang et al., 2023)                   | 1B     | 56.1                 | –                        | 82.8 | 71.4   |
| VideoMAEv2 (Wang et al., 2023)                   | 1B     | 56.1                 | –                        | 82.8 | 71.4   |
| VideoMAEv2 (Wang et al., 2023)                   | 1B     | 56.1                 | –                        | 82.8 | 71.4   |
| VideoMAEv2 (Wang et al., 2023)                   | 1B     | 56.1                 | –                        | 82.8 | 71.4   |
| VideoMAEv2 (Wang et al., 2023)                   | 1B     | 56.1                 | –                        | 82.8 | 71.4   |
| InternVideo2-1B (Wang et al., 2024b)             | 1B     | 67.3                 | –                        | 87.9 | –      |
| InternVideo2-1B (Wang et al., 2024b)             | 1B     | 67.3                 | –                        | 87.9 | –      |
| InternVideo2-1B (Wang et al., 2024b)             | 1B     | 67.3                 | –                        | 87.9 | –      |
| InternVideo2-1B (Wang et al., 2024b)             | 1B     | 67.3                 | –                        | 87.9 | –      |
| InternVideo2-1B (Wang et al., 2024b)             | 1B     | 67.3                 | –                        | 87.9 | –      |
| InternVideo2-1B (Wang et al., 2024b)             | 1B     | 67.3                 | –                        | 87.9 | –      |
| VideoPrism (Zhao et al., 2024)                   | 1B     | 68.5                 | 71.3                     | 87.6 | –      |
| VideoPrism (Zhao et al., 2024)                   | 1B     | 68.5                 | 71.3                     | 87.6 | –      |
| VideoPrism (Zhao et al., 2024)                   | 1B     | 68.5                 | 71.3                     | 87.6 | –      |
| VideoPrism (Zhao et al., 2024)                   | 1B     | 68.5                 | 71.3                     | 87.6 | –      |
| VideoPrism (Zhao et al., 2024)                   | 1B     | 68.5                 | 71.3                     | 87.6 | –      |
| VideoPrism (Zhao et al., 2024)                   | 1B     | 68.5                 | 71.3                     | 87.6 | –      |
| DINOv3 ViT-H+ (Siméoni et al., 2025)             | 0.8B   | 69.8                 | –                        | 86.7 | 87.9   |
| DINOv3 ViT-H+ (Siméoni et al., 2025)             | 0.8B   | 69.8                 | –                        | 86.7 | 87.9   |
| DINOv3 ViT-H+ (Siméoni et al., 2025)             | 0.8B   | 69.8                 | –                        | 86.7 | 87.9   |
| DINOv3 ViT-H+ (Siméoni et al., 2025)             | 0.8B   | 69.8                 | –                        | 86.7 | 87.9   |
| DINOv3 ViT-H+ (Siméoni et al., 2025)             | 0.8B   | 69.8                 | –                        | 86.7 | 87.9   |
| DINOv3 ViT-H+ (Siméoni et al., 2025)             | 0.8B   | 69.8                 | –                        | 86.7 | 87.9   |
| DINOv3 (Siméoni et al., 2025)                    | 7B     | 70.1                 | –                        | 87.8 | 88.4   |
| DINOv3 (Siméoni et al., 2025)                    | 7B     | 70.1                 | –                        | 87.8 | 88.4   |
| DINOv3 (Siméoni et al., 2025)                    | 7B     | 70.1                 | –                        | 87.8 | 88.4   |
| DINOv3 (Siméoni et al., 2025)                    | 7B     | 70.1                 | –                        | 87.8 | 88.4   |
| DINOv3 (Siméoni et al., 2025)                    | 7B     | 70.1                 | –                        | 87.8 | 88.4   |
| DINOv3 (Siméoni et al., 2025)                    | 7B     | 70.1                 | –                        | 87.8 | 88.4   |
| Image Encoders Evaluated Using the Same Protocol |        |                      |                          |      |        |
| DINOv2 (Darcet et al., 2023)                     | 1.1B   | 50.7                 | 82.5                     | 83.6 | 86.1   |
| DINOv2 (Darcet et al., 2023)                     | 1.1B   | 50.7                 | 82.5                     | 83.6 | 86.1   |
| DINOv2 (Darcet et al., 2023)                     | 1.1B   | 50.7                 | 82.5                     | 83.6 | 86.1   |
| DINOv2 (Darcet et al., 2023)                     | 1.1B   | 50.7                 | 82.5                     | 83.6 | 86.1   |
| DINOv2 (Darcet et al., 2023)                     | 1.1B   | 50.7                 | 82.5                     | 83.6 | 86.1   |
| DINOv2 (Darcet et al., 2023)                     | 1.1B   | 50.7                 | 82.5                     | 83.6 | 86.1   |
| PEcore G (Bolya et al., 2025)                    | 1.9B   | 55.4                 | 76.9                     | 88.5 | 87.6^∗ |
| PEcore G (Bolya et al., 2025)                    | 1.9B   | 55.4                 | 76.9                     | 88.5 | 87.6^∗ |
| PEcore G (Bolya et al., 2025)                    | 1.9B   | 55.4                 | 76.9                     | 88.5 | 87.6^∗ |
| PEcore G (Bolya et al., 2025)                    | 1.9B   | 55.4                 | 76.9                     | 88.5 | 87.6^∗ |
| PEcore G (Bolya et al., 2025)                    | 1.9B   | 55.4                 | 76.9                     | 88.5 | 87.6^∗ |
| PEcore G (Bolya et al., 2025)                    | 1.9B   | 55.4                 | 76.9                     | 88.5 | 87.6^∗ |
| SigLIP2 (Tschannen et al., 2025)                 | 1.2B   | 49.9                 | 75.3                     | 87.3 | 88.0   |
| SigLIP2 (Tschannen et al., 2025)                 | 1.2B   | 49.9                 | 75.3                     | 87.3 | 88.0   |
| SigLIP2 (Tschannen et al., 2025)                 | 1.2B   | 49.9                 | 75.3                     | 87.3 | 88.0   |
| SigLIP2 (Tschannen et al., 2025)                 | 1.2B   | 49.9                 | 75.3                     | 87.3 | 88.0   |
| SigLIP2 (Tschannen et al., 2025)                 | 1.2B   | 49.9                 | 75.3                     | 87.3 | 88.0   |
| SigLIP2 (Tschannen et al., 2025)                 | 1.2B   | 49.9                 | 75.3                     | 87.3 | 88.0   |
| Video Encoders Evaluated Using the Same Protocol |        |                      |                          |      |        |
| InternVideo22s-1B (Wang et al., 2024b)           | 1B     | 69.7                 | 86.4                     | 89.4 | 85.8   |
| InternVideo22s-1B (Wang et al., 2024b)           | 1B     | 69.7                 | 86.4                     | 89.4 | 85.8   |
| InternVideo22s-1B (Wang et al., 2024b)           | 1B     | 69.7                 | 86.4                     | 89.4 | 85.8   |
| InternVideo22s-1B (Wang et al., 2024b)           | 1B     | 69.7                 | 86.4                     | 89.4 | 85.8   |
| InternVideo22s-1B (Wang et al., 2024b)           | 1B     | 69.7                 | 86.4                     | 89.4 | 85.8   |
| InternVideo22s-1B (Wang et al., 2024b)           | 1B     | 69.7                 | 86.4                     | 89.4 | 85.8   |
| V-JEPA ViT-H (Bardes et al., 2024)               | 600M   | 74.3                 | 87.9                     | 84.5 | 80.0   |
| V-JEPA ViT-H (Bardes et al., 2024)               | 600M   | 74.3                 | 87.9                     | 84.5 | 80.0   |
| V-JEPA ViT-H (Bardes et al., 2024)               | 600M   | 74.3                 | 87.9                     | 84.5 | 80.0   |
| V-JEPA ViT-H (Bardes et al., 2024)               | 600M   | 74.3                 | 87.9                     | 84.5 | 80.0   |
| V-JEPA ViT-H (Bardes et al., 2024)               | 600M   | 74.3                 | 87.9                     | 84.5 | 80.0   |
| V-JEPA ViT-H (Bardes et al., 2024)               | 600M   | 74.3                 | 87.9                     | 84.5 | 80.0   |
| V-JEPA 2 ViT-g (Assran et al., 2025)             | 1B     | 77.3                 | 90.2                     | 87.3 | 85.1   |
| V-JEPA 2 ViT-g (Assran et al., 2025)             | 1B     | 77.3                 | 90.2                     | 87.3 | 85.1   |
| V-JEPA 2 ViT-g (Assran et al., 2025)             | 1B     | 77.3                 | 90.2                     | 87.3 | 85.1   |
| V-JEPA 2 ViT-g (Assran et al., 2025)             | 1B     | 77.3                 | 90.2                     | 87.3 | 85.1   |
| V-JEPA 2 ViT-g (Assran et al., 2025)             | 1B     | 77.3                 | 90.2                     | 87.3 | 85.1   |
| V-JEPA 2 ViT-g (Assran et al., 2025)             | 1B     | 77.3                 | 90.2                     | 87.3 | 85.1   |
| V-JEPA 2.1 ViT-g                                 | 1B     | 76.9                 | 89.0                     | 87.0 | 84.8   |
| V-JEPA 2.1 ViT-g                                 | 1B     | 76.9                 | 89.0                     | 87.0 | 84.8   |
| V-JEPA 2.1 ViT-g                                 | 1B     | 76.9                 | 89.0                     | 87.0 | 84.8   |
| V-JEPA 2.1 ViT-g                                 | 1B     | 76.9                 | 89.0                     | 87.0 | 84.8   |
| V-JEPA 2.1 ViT-g                                 | 1B     | 76.9                 | 89.0                     | 87.0 | 84.8   |
| V-JEPA 2.1 ViT-g                                 | 1B     | 76.9                 | 89.0                     | 87.0 | 84.8   |
| V-JEPA 2.1 ViT-G                                 | 2B     | 77.7                 | 89.2                     | 87.7 | 85.5   |
| V-JEPA 2.1 ViT-G                                 | 2B     | 77.7                 | 89.2                     | 87.7 | 85.5   |
| V-JEPA 2.1 ViT-G                                 | 2B     | 77.7                 | 89.2                     | 87.7 | 85.5   |
| V-JEPA 2.1 ViT-G                                 | 2B     | 77.7                 | 89.2                     | 87.7 | 85.5   |
| V-JEPA 2.1 ViT-G                                 | 2B     | 77.7                 | 89.2                     | 87.7 | 85.5   |
| V-JEPA 2.1 ViT-G                                 | 2B     | 77.7                 | 89.2                     | 87.7 | 85.5   |

Real-world video reasoning requires recognizing static visual cues (i.e, objects, textures, scene layouts) as well as dynamic patterns (i.e, gestures, hand-object interactions, camera motion, long-term temporal evolution).
To capture this dual nature, we evaluate the representations learned during pretraining on four complementary classification datasets.
Something-Something v2 (Goyal et al., 2017) and Diving-48 (Li et al., 2018) assess motion-centric understanding, as their labels require modeling multi-frame dynamics to correctly identify the action.
In contrast, Kinetics-400 (Kay et al., 2017) and ImageNet-1K (Deng et al., 2009) primarily measure appearance-based recognition, since many of their classes can be predicted from a single frame, even when the label describes an action.

##### Task.

We compare the video classification performance of V-JEPA 2.1 against a broad set of visual encoders.
For image-based self-supervised models, we include DINOv2 with registers (Darcet et al., 2023) and the more recent DINOv3 (Siméoni et al., 2025), both representing state-of-the-art in image-only pretraining.
We further evaluate against leading image–text contrastive approaches, including SigLIP2 (Tschannen et al., 2025) and the Perception Encoder PEcoreG (Bolya et al., 2025). For video models, we benchmark against the previous V-JEPA (Bardes et al., 2024) and V-JEPA 2 (Assran et al., 2025), as well as InternVideo2s2-1B (Wang et al., 2024b), a state-of-the-art video encoder trained primarily through vision–text contrastive objectives.

In addition, we report comparisons with results available in the literature for VideoMAEv2 (Wang et al., 2023), InternVideo2-1B (Wang et al., 2024b), VideoPrism (Zhang et al., 2024), and DINOv3 (Siméoni et al., 2025). Note that these models are evaluated under similar frozen-probe protocols, but their attentive heads differ from ours. For instance, DINOv3 augments its probe with explicit spatial and temporal positional embeddings and applies a 3D factorized RoPE across its attention blocks. In contrast, our V-JEPA 2.1 encoder already encodes spatio–temporal structure in its features, allowing our probe to operate without such additional components.

##### Evaluation protocol.

Following the protocol proposed by Assran et al. (2025), we train a 4-layers attentive probe on top of the frozen encoder features using the respective training data from each task.
The attentive probe consists of four transformer blocks followed by a final cross-attention mechanism that employs a learnable query token.
At inference, we sampled several clips with a fixed number of frames from the video, and we averaged the classification logits across clips.

##### Results.

Table [9](#S3.T9) summarizes the global video understanding performance of V-JEPA 2.1, previous V-JEPA models, and other strong visual encoders. V-JEPA 2.1 ViT-G achieves a top-1 accuracy of 77.7 on SSv2, setting a new absolute state-of-the-art on the task compared to 77.5 for InternVideo2 full fine-tuning, 77.3 for V-JEPA 2, 70.1 for DINOv3 ViT-7B and 69.7 for InternVideo2 using the same protocol, demonstrating a strong understanding of video dynamics. Our model is also highly-competitive in appearance-based tasks, reaching 87.7 on K400 and 85.5 on IN1K.
These results show that properly designing the loss over context tokens, together with deep self-supervision, enables fine-grained dense features that also capture strong global scene understanding.
We also observe consistent improvements with model scaling from ViT-g to ViT-G with an average improvement of +0.6 points.

<a id="section-3-8"></a>

### 3.8 Video Question Answering

In this section, we evaluate V-JEPA 2.1 on Video Question Answering (VidQA), by training a Video Large Language Model (VidLLM) using V-JEPA 2.1 encoder and Llama 3.1 8B LLM as the backbone, following the recipe proposed by Assran et al. (2025).

<a id="table-10"></a>

> Table 10: VideoQA results. We report the performance of VJEPA 2.1 trained with Llama 3.1 8B backbone on several popular temporal video understanding datasets. We train on a modified subset of the PerceptionLM (Cho et al., 2025) data, and compare to VJEPA 2 (Assran et al., 2025) by training it on the same data regime. VJEPA 2.1 achieves comparatively better performance than VJEPA 2 on several video understanding tasks which require both rich visual information and temporal understanding. For PerceptionTest (Pătrăucean et al., 2023), we report the validation accuracy, as the test server to compute the test accuracy (indicated by \*) is no longer active.

| Method                                                                            | Params<br>Enc / LLM | Avg. | PerceptionTest<br>Test Acc | MVP<br>Paired-Acc | TempCompass<br>multi-choice | TemporalBench<br>(MBA-short QA) | TOMATO<br>Acc | TVBench<br>Acc | MVBench<br>Acc |
| --------------------------------------------------------------------------------- | ------------------- | ---- | -------------------------- | ----------------- | --------------------------- | ------------------------------- | ------------- | -------------- | -------------- |
| Method                                                                            | Params<br>Enc / LLM | Avg. | PerceptionTest<br>Test Acc | MVP<br>Paired-Acc | TempCompass<br>multi-choice | TemporalBench<br>(MBA-short QA) | TOMATO<br>Acc | TVBench<br>Acc | MVBench<br>Acc |
| Method                                                                            | Params<br>Enc / LLM | Avg. | PerceptionTest<br>Test Acc | MVP<br>Paired-Acc | TempCompass<br>multi-choice | TemporalBench<br>(MBA-short QA) | TOMATO<br>Acc | TVBench<br>Acc | MVBench<br>Acc |
| Method                                                                            | Params<br>Enc / LLM | Avg. | PerceptionTest<br>Test Acc | MVP<br>Paired-Acc | TempCompass<br>multi-choice | TemporalBench<br>(MBA-short QA) | TOMATO<br>Acc | TVBench<br>Acc | MVBench<br>Acc |
| Method                                                                            | Params<br>Enc / LLM | Avg. | PerceptionTest<br>Test Acc | MVP<br>Paired-Acc | TempCompass<br>multi-choice | TemporalBench<br>(MBA-short QA) | TOMATO<br>Acc | TVBench<br>Acc | MVBench<br>Acc |
| Method                                                                            | Params<br>Enc / LLM | Avg. | PerceptionTest<br>Test Acc | MVP<br>Paired-Acc | TempCompass<br>multi-choice | TemporalBench<br>(MBA-short QA) | TOMATO<br>Acc | TVBench<br>Acc | MVBench<br>Acc |
| Method                                                                            | Params<br>Enc / LLM | Avg. | PerceptionTest<br>Test Acc | MVP<br>Paired-Acc | TempCompass<br>multi-choice | TemporalBench<br>(MBA-short QA) | TOMATO<br>Acc | TVBench<br>Acc | MVBench<br>Acc |
| Method                                                                            | Params<br>Enc / LLM | Avg. | PerceptionTest<br>Test Acc | MVP<br>Paired-Acc | TempCompass<br>multi-choice | TemporalBench<br>(MBA-short QA) | TOMATO<br>Acc | TVBench<br>Acc | MVBench<br>Acc |
| Method                                                                            | Params<br>Enc / LLM | Avg. | PerceptionTest<br>Test Acc | MVP<br>Paired-Acc | TempCompass<br>multi-choice | TemporalBench<br>(MBA-short QA) | TOMATO<br>Acc | TVBench<br>Acc | MVBench<br>Acc |
| Method                                                                            | Params<br>Enc / LLM | Avg. | PerceptionTest<br>Test Acc | MVP<br>Paired-Acc | TempCompass<br>multi-choice | TemporalBench<br>(MBA-short QA) | TOMATO<br>Acc | TVBench<br>Acc | MVBench<br>Acc |
| $\leq 8B$ Video Language Models Results Reported in the Literature                |                     |      |                            |                   |                             |                                 |               |                |                |
| $\leq 8B$ Video Language Models Results Reported in the Literature                |                     |      |                            |                   |                             |                                 |               |                |                |
| $\leq 8B$ Video Language Models Results Reported in the Literature                |                     |      |                            |                   |                             |                                 |               |                |                |
| InternVL-2.5 (Chen et al., 2024)                                                  | 300M/7B             | 52.1 | 68.9                       | 39.9              | 68.3                        | 24.3                            | 29.4          | 61.6           | 72.6           |
| InternVL-2.5 (Chen et al., 2024)                                                  | 300M/7B             | 52.1 | 68.9                       | 39.9              | 68.3                        | 24.3                            | 29.4          | 61.6           | 72.6           |
| InternVL-2.5 (Chen et al., 2024)                                                  | 300M/7B             | 52.1 | 68.9                       | 39.9              | 68.3                        | 24.3                            | 29.4          | 61.6           | 72.6           |
| InternVL-2.5 (Chen et al., 2024)                                                  | 300M/7B             | 52.1 | 68.9                       | 39.9              | 68.3                        | 24.3                            | 29.4          | 61.6           | 72.6           |
| InternVL-2.5 (Chen et al., 2024)                                                  | 300M/7B             | 52.1 | 68.9                       | 39.9              | 68.3                        | 24.3                            | 29.4          | 61.6           | 72.6           |
| InternVL-2.5 (Chen et al., 2024)                                                  | 300M/7B             | 52.1 | 68.9                       | 39.9              | 68.3                        | 24.3                            | 29.4          | 61.6           | 72.6           |
| InternVL-2.5 (Chen et al., 2024)                                                  | 300M/7B             | 52.1 | 68.9                       | 39.9              | 68.3                        | 24.3                            | 29.4          | 61.6           | 72.6           |
| InternVL-2.5 (Chen et al., 2024)                                                  | 300M/7B             | 52.1 | 68.9                       | 39.9              | 68.3                        | 24.3                            | 29.4          | 61.6           | 72.6           |
| InternVL-2.5 (Chen et al., 2024)                                                  | 300M/7B             | 52.1 | 68.9                       | 39.9              | 68.3                        | 24.3                            | 29.4          | 61.6           | 72.6           |
| InternVL-2.5 (Chen et al., 2024)                                                  | 300M/7B             | 52.1 | 68.9                       | 39.9              | 68.3                        | 24.3                            | 29.4          | 61.6           | 72.6           |
| Qwen2VL (Wang et al., 2024a)                                                      | 675M/7B             | 47.0 | 66.9                       | 29.2              | 67.9                        | 20.4                            | 31.5          | 46.0           | 67.0           |
| Qwen2VL (Wang et al., 2024a)                                                      | 675M/7B             | 47.0 | 66.9                       | 29.2              | 67.9                        | 20.4                            | 31.5          | 46.0           | 67.0           |
| Qwen2VL (Wang et al., 2024a)                                                      | 675M/7B             | 47.0 | 66.9                       | 29.2              | 67.9                        | 20.4                            | 31.5          | 46.0           | 67.0           |
| Qwen2VL (Wang et al., 2024a)                                                      | 675M/7B             | 47.0 | 66.9                       | 29.2              | 67.9                        | 20.4                            | 31.5          | 46.0           | 67.0           |
| Qwen2VL (Wang et al., 2024a)                                                      | 675M/7B             | 47.0 | 66.9                       | 29.2              | 67.9                        | 20.4                            | 31.5          | 46.0           | 67.0           |
| Qwen2VL (Wang et al., 2024a)                                                      | 675M/7B             | 47.0 | 66.9                       | 29.2              | 67.9                        | 20.4                            | 31.5          | 46.0           | 67.0           |
| Qwen2VL (Wang et al., 2024a)                                                      | 675M/7B             | 47.0 | 66.9                       | 29.2              | 67.9                        | 20.4                            | 31.5          | 46.0           | 67.0           |
| Qwen2VL (Wang et al., 2024a)                                                      | 675M/7B             | 47.0 | 66.9                       | 29.2              | 67.9                        | 20.4                            | 31.5          | 46.0           | 67.0           |
| Qwen2VL (Wang et al., 2024a)                                                      | 675M/7B             | 47.0 | 66.9                       | 29.2              | 67.9                        | 20.4                            | 31.5          | 46.0           | 67.0           |
| Qwen2VL (Wang et al., 2024a)                                                      | 675M/7B             | 47.0 | 66.9                       | 29.2              | 67.9                        | 20.4                            | 31.5          | 46.0           | 67.0           |
| Qwen2.5VL (Qwen Team et al., 2025)                                                | 1B/7B               | 49.7 | 70.5                       | 36.7              | 71.7                        | 24.5                            | 24.6          | 50.5           | 69.6           |
| Qwen2.5VL (Qwen Team et al., 2025)                                                | 1B/7B               | 49.7 | 70.5                       | 36.7              | 71.7                        | 24.5                            | 24.6          | 50.5           | 69.6           |
| Qwen2.5VL (Qwen Team et al., 2025)                                                | 1B/7B               | 49.7 | 70.5                       | 36.7              | 71.7                        | 24.5                            | 24.6          | 50.5           | 69.6           |
| Qwen2.5VL (Qwen Team et al., 2025)                                                | 1B/7B               | 49.7 | 70.5                       | 36.7              | 71.7                        | 24.5                            | 24.6          | 50.5           | 69.6           |
| Qwen2.5VL (Qwen Team et al., 2025)                                                | 1B/7B               | 49.7 | 70.5                       | 36.7              | 71.7                        | 24.5                            | 24.6          | 50.5           | 69.6           |
| Qwen2.5VL (Qwen Team et al., 2025)                                                | 1B/7B               | 49.7 | 70.5                       | 36.7              | 71.7                        | 24.5                            | 24.6          | 50.5           | 69.6           |
| Qwen2.5VL (Qwen Team et al., 2025)                                                | 1B/7B               | 49.7 | 70.5                       | 36.7              | 71.7                        | 24.5                            | 24.6          | 50.5           | 69.6           |
| Qwen2.5VL (Qwen Team et al., 2025)                                                | 1B/7B               | 49.7 | 70.5                       | 36.7              | 71.7                        | 24.5                            | 24.6          | 50.5           | 69.6           |
| Qwen2.5VL (Qwen Team et al., 2025)                                                | 1B/7B               | 49.7 | 70.5                       | 36.7              | 71.7                        | 24.5                            | 24.6          | 50.5           | 69.6           |
| Qwen2.5VL (Qwen Team et al., 2025)                                                | 1B/7B               | 49.7 | 70.5                       | 36.7              | 71.7                        | 24.5                            | 24.6          | 50.5           | 69.6           |
| PLM 8B (Cho et al., 2025)                                                         | 1B/8B               | 56.7 | 82.7\*                     | 39.7              | 72.7                        | 28.3                            | 33.2          | 63.5           | 77.1           |
| PLM 8B (Cho et al., 2025)                                                         | 1B/8B               | 56.7 | 82.7\*                     | 39.7              | 72.7                        | 28.3                            | 33.2          | 63.5           | 77.1           |
| PLM 8B (Cho et al., 2025)                                                         | 1B/8B               | 56.7 | 82.7\*                     | 39.7              | 72.7                        | 28.3                            | 33.2          | 63.5           | 77.1           |
| PLM 8B (Cho et al., 2025)                                                         | 1B/8B               | 56.7 | 82.7\*                     | 39.7              | 72.7                        | 28.3                            | 33.2          | 63.5           | 77.1           |
| PLM 8B (Cho et al., 2025)                                                         | 1B/8B               | 56.7 | 82.7\*                     | 39.7              | 72.7                        | 28.3                            | 33.2          | 63.5           | 77.1           |
| PLM 8B (Cho et al., 2025)                                                         | 1B/8B               | 56.7 | 82.7\*                     | 39.7              | 72.7                        | 28.3                            | 33.2          | 63.5           | 77.1           |
| PLM 8B (Cho et al., 2025)                                                         | 1B/8B               | 56.7 | 82.7\*                     | 39.7              | 72.7                        | 28.3                            | 33.2          | 63.5           | 77.1           |
| PLM 8B (Cho et al., 2025)                                                         | 1B/8B               | 56.7 | 82.7\*                     | 39.7              | 72.7                        | 28.3                            | 33.2          | 63.5           | 77.1           |
| PLM 8B (Cho et al., 2025)                                                         | 1B/8B               | 56.7 | 82.7\*                     | 39.7              | 72.7                        | 28.3                            | 33.2          | 63.5           | 77.1           |
| PLM 8B (Cho et al., 2025)                                                         | 1B/8B               | 56.7 | 82.7\*                     | 39.7              | 72.7                        | 28.3                            | 33.2          | 63.5           | 77.1           |
| VJEPA 2 ViT-g384 (Assran et al., 2025)                                            | 1B/8B               | 59.5 | 84.0\*                     | 44.5              | 76.9                        | 36.7                            | 40.3          | 60.6           | 73.5           |
| VJEPA 2 ViT-g384 (Assran et al., 2025)                                            | 1B/8B               | 59.5 | 84.0\*                     | 44.5              | 76.9                        | 36.7                            | 40.3          | 60.6           | 73.5           |
| VJEPA 2 ViT-g384 (Assran et al., 2025)                                            | 1B/8B               | 59.5 | 84.0\*                     | 44.5              | 76.9                        | 36.7                            | 40.3          | 60.6           | 73.5           |
| VJEPA 2 ViT-g384 (Assran et al., 2025)                                            | 1B/8B               | 59.5 | 84.0\*                     | 44.5              | 76.9                        | 36.7                            | 40.3          | 60.6           | 73.5           |
| VJEPA 2 ViT-g384 (Assran et al., 2025)                                            | 1B/8B               | 59.5 | 84.0\*                     | 44.5              | 76.9                        | 36.7                            | 40.3          | 60.6           | 73.5           |
| VJEPA 2 ViT-g384 (Assran et al., 2025)                                            | 1B/8B               | 59.5 | 84.0\*                     | 44.5              | 76.9                        | 36.7                            | 40.3          | 60.6           | 73.5           |
| VJEPA 2 ViT-g384 (Assran et al., 2025)                                            | 1B/8B               | 59.5 | 84.0\*                     | 44.5              | 76.9                        | 36.7                            | 40.3          | 60.6           | 73.5           |
| VJEPA 2 ViT-g384 (Assran et al., 2025)                                            | 1B/8B               | 59.5 | 84.0\*                     | 44.5              | 76.9                        | 36.7                            | 40.3          | 60.6           | 73.5           |
| VJEPA 2 ViT-g384 (Assran et al., 2025)                                            | 1B/8B               | 59.5 | 84.0\*                     | 44.5              | 76.9                        | 36.7                            | 40.3          | 60.6           | 73.5           |
| VJEPA 2 ViT-g384 (Assran et al., 2025)                                            | 1B/8B               | 59.5 | 84.0\*                     | 44.5              | 76.9                        | 36.7                            | 40.3          | 60.6           | 73.5           |
| Models trained in this paper using filtered Perception LM data (Cho et al., 2025) |                     |      |                            |                   |                             |                                 |               |                |                |
| Models trained in this paper using filtered Perception LM data (Cho et al., 2025) |                     |      |                            |                   |                             |                                 |               |                |                |
| Models trained in this paper using filtered Perception LM data (Cho et al., 2025) |                     |      |                            |                   |                             |                                 |               |                |                |
| VJEPA 2 ViT-g384                                                                  | 1B/8B               | 57.8 | 80.1                       | 40.9              | 74.1                        | 32.3                            | 41.4          | 62.6           | 73.3           |
| VJEPA 2 ViT-g384                                                                  | 1B/8B               | 57.8 | 80.1                       | 40.9              | 74.1                        | 32.3                            | 41.4          | 62.6           | 73.3           |
| VJEPA 2 ViT-g384                                                                  | 1B/8B               | 57.8 | 80.1                       | 40.9              | 74.1                        | 32.3                            | 41.4          | 62.6           | 73.3           |
| VJEPA 2 ViT-g384                                                                  | 1B/8B               | 57.8 | 80.1                       | 40.9              | 74.1                        | 32.3                            | 41.4          | 62.6           | 73.3           |
| VJEPA 2 ViT-g384                                                                  | 1B/8B               | 57.8 | 80.1                       | 40.9              | 74.1                        | 32.3                            | 41.4          | 62.6           | 73.3           |
| VJEPA 2 ViT-g384                                                                  | 1B/8B               | 57.8 | 80.1                       | 40.9              | 74.1                        | 32.3                            | 41.4          | 62.6           | 73.3           |
| VJEPA 2 ViT-g384                                                                  | 1B/8B               | 57.8 | 80.1                       | 40.9              | 74.1                        | 32.3                            | 41.4          | 62.6           | 73.3           |
| VJEPA 2 ViT-g384                                                                  | 1B/8B               | 57.8 | 80.1                       | 40.9              | 74.1                        | 32.3                            | 41.4          | 62.6           | 73.3           |
| VJEPA 2 ViT-g384                                                                  | 1B/8B               | 57.8 | 80.1                       | 40.9              | 74.1                        | 32.3                            | 41.4          | 62.6           | 73.3           |
| VJEPA 2 ViT-g384                                                                  | 1B/8B               | 57.8 | 80.1                       | 40.9              | 74.1                        | 32.3                            | 41.4          | 62.6           | 73.3           |
| VJEPA 2.1 ViT-G384                                                                | 2B/8B               | 57.9 | 83.1                       | 43.2              | 74                          | 28.5                            | 38            | 62.8           | 75.4           |
| VJEPA 2.1 ViT-G384                                                                | 2B/8B               | 57.9 | 83.1                       | 43.2              | 74                          | 28.5                            | 38            | 62.8           | 75.4           |
| VJEPA 2.1 ViT-G384                                                                | 2B/8B               | 57.9 | 83.1                       | 43.2              | 74                          | 28.5                            | 38            | 62.8           | 75.4           |
| VJEPA 2.1 ViT-G384                                                                | 2B/8B               | 57.9 | 83.1                       | 43.2              | 74                          | 28.5                            | 38            | 62.8           | 75.4           |
| VJEPA 2.1 ViT-G384                                                                | 2B/8B               | 57.9 | 83.1                       | 43.2              | 74                          | 28.5                            | 38            | 62.8           | 75.4           |
| VJEPA 2.1 ViT-G384                                                                | 2B/8B               | 57.9 | 83.1                       | 43.2              | 74                          | 28.5                            | 38            | 62.8           | 75.4           |
| VJEPA 2.1 ViT-G384                                                                | 2B/8B               | 57.9 | 83.1                       | 43.2              | 74                          | 28.5                            | 38            | 62.8           | 75.4           |
| VJEPA 2.1 ViT-G384                                                                | 2B/8B               | 57.9 | 83.1                       | 43.2              | 74                          | 28.5                            | 38            | 62.8           | 75.4           |
| VJEPA 2.1 ViT-G384                                                                | 2B/8B               | 57.9 | 83.1                       | 43.2              | 74                          | 28.5                            | 38            | 62.8           | 75.4           |
| VJEPA 2.1 ViT-G384                                                                | 2B/8B               | 57.9 | 83.1                       | 43.2              | 74                          | 28.5                            | 38            | 62.8           | 75.4           |

##### Task.

We compare the VidQA performance of V-JEPA 2.1 with popular open-source multimodal models reported in the literature, where the LLM backbone size is $\leq$ 8B. Following the protocol set of Assran et al. (2025), we report performance on video understanding benchmarks which require rich visual and temporal understanding, such as PerceptionTest (Pătrăucean et al., 2023), Minimal Video Pairs (MVP) (Krojer et al., 2024), TempCompass (Liu et al., 2024), TemporalBench (Cai et al., 2024), TOMATO (Shangguan et al., 2024) and MVBench (Li et al., 2024).

##### Evaluation protocol.

We train our Video-LLM model using a subset of PerceptionLM that is publicly available (Cho et al., 2025).
Starting with this data, we perform data quality filtering using domain filters, vision-text misalignment filters, and an external multimodal LLM, Qwen3VL, as a data-quality judge, assigning scores to each data samples. This process resulted us to filter out and remove 18% of the training data.
It is important to note that we do not rephrase any data from PerceptionLM (Cho et al., 2025) using this setup - we only filter the data based on the model’s judgement.

We reproduced LLM alignment of VJEPA 2 on this new data, and compare our model, VJEPA 2.1, with it. We follow the same three-stage training procedure from Assran et al. (2025) to train VJEPA 2.1 LLM, starting from image-text captioning to progressively training on higher quality image and video-text captioning and QA data. We further add a fourth stage of alignment, where we expand the context length of the base LLM to support 64 frames of video input, compared to 32 frames supported by VJEPA 2 (Assran et al., 2025).
We primarily use VJEPA 2.1 in video-only mode in our experiments, to better compare with VJEPA 2. Interestingly, we find adding a final post-training stage using PerceptionTest training set further improves performance on all downstream tasks.

##### Results.

Table [10](#S3.T10) summarizes the results on VidQA evaluation tasks. Comparing VJEPA 2 and VJEPA 2.1 on the same data, we find on average VJEPA 2.1 to be slightly better, with significant improvements on PerceptionTest, Minimal Video Pairs, and crucially, improvement on datasets requiring rich visual semantics - MVBench and TVBench. We observe VJEPA 2.1 to be worse on TemporalBench and TOMATO - both datasets requiring understanding of the motion events, but on shorter videos.

Compared to results reported in the literature, VJEPA 2.1 slightly underperforms results reported Assran et al. (2025) which uses significantly alignment data (88.5 million samples in (Assran et al., 2023) vs 72.5 million samples in VJEPA 2.1)
Nevertheless, VJEPA 2.1 is competitive with state-of-the-art, outperforming most open-source multimodal LLMs with similar model size.

<a id="figure-14"></a>

![step1_img](images/step1_img.jpg)

> Figure 14: Comparison of dense features produced by different SSL methods on a single image. We compare DINOv2 ViT-g (Oquab et al., 2023), DINOv3 ViT-H+ (Siméoni et al., 2025) and V-JEPA 2 ViT-g (Assran et al., 2025) against V-JEPA 2.1 ViT-G. Images are resized so that their shorter side is set to 1024 pixels, after which they are processed using the 2D convolution image tokenizer.

<a id="figure-15"></a>

![1](images/1.jpg)

> Figure 15: V-JEPA 2.1 unlocks dense features from video. Qualitative results on Ego4D (1080px), Cityscapes (1080px), Diving48 (768px), and MOCA (768px) illustrate the strong temporal consistency of the dense features produced by our ViT-G model, particularly on dynamic objects. Since we process entire video sequences, we employ the 3D convolutional video tokenizer.

<a id="section-3-9"></a>

### 3.9 Qualitative results of V-JEPA 2.1 Dense Features

Figure [14](#S3.F14) presents a comparison of dense feature maps obtained from a single image using V-JEPA 2.1 ViT-G, DINOv2 ViT-g (Oquab et al., 2023), DINOv3 ViT-H+ (Siméoni et al., 2025) and V-JEPA 2 ViT-g (Assran et al., 2025).
We project each encoder’s feature space into three dimensions using PCA.
Following Siméoni et al. (2025), we permute the three components across the six possible RGB channels permutations, and we display the most visually appealing.
The qualitative results in Figure [14](#S3.F14) illustrate the high-quality of V-JEPA 2.1 dense feature maps obtained from a single image, which show fine-grained and precise identification of objects, such as the cat’s fur details or pedestrians in Cityscapes scenes.
Figure [15](#S3.F15) further extends this comparison to full video sequences of 64 frames, showing temporal consistent dense maps across diverse scenarios, including egocentric videos from Ego4D (Grauman et al., 2022), Cityscapes sequences (Cordts et al., 2016), Diving48 videos (Li et al., 2018) and animal camouflage footage from MOC (Lamdouar et al., 2020).

<a id="section-3-10"></a>

### 3.10 Family of distilled models

We follow the same protocol to evaluate our distilled ViT-L and ViT-B models. Table LABEL:tab:distill_vs_scratch presents our results, where we observe a significant improvement in all our benchmarks between the ViT-L trained from scratch and the ViT-L distilled from ViT-G, almost closing the gap with ViT-G performance. On action recognition on SSv2, performance improves from 74.2% to 76.5%, almost reaching 77.7% from ViT-G. In image segmentation on ADE20k, performance improves from 42.0 mIoU to 46.7 mIoU. In depth estimation and video segmentation, the ViT-L distilled is even closer to ViT-G, with 2.490 RMSE on KITTI, close to 2.461 RMSE, and 68.7 $\mathcal{J}\&\mathcal{F}$-Mean on DAVIS, close to 67.0 $\mathcal{J}\&\mathcal{F}$-Mean. Finally, our ViT-B offers competitive performance with our ViT-L trained from scratch.

<a id="section-4"></a>

## 4 Related work

##### Self-Supervised Learning.

Early SSL approaches in vision focus on simple pretext tasks such as predicting the relative position of image patches (Doersch et al., 2015), reordering shuffled patches (Noroozi and Favaro, 2016; Misra and Maaten, 2020), inpainting missing regions (Pathak et al., 2016), re-colorizing grayscale images (Zhang et al., 2016), or predicting applied image transformations (Gidaris et al., 2018). Beyond hand-crafted tasks, view-invariant approaches proposed to use a joint-embedding architecture to learn invariances to visual transformations, which led to significant advances in SSL, with contrastive approaches (Hénaff et al., 2019; He et al., 2020; Chen et al., 2020), non-contrastive approaches (Chen and He, 2020; Grill et al., 2020b; Bardes et al., 2021), or clustering-based techniques (Caron et al., 2018, 2020). Later, the adoption of vision transformers (Dosovitskiy, 2020) became the standard in self-supervised learning, first by revisiting existing view-invariant approaches (Chen et al., 2021; Caron et al., 2021), and then with masked image modeling approaches, which can operate in pixel space (Xie et al., 2021b; Wei et al., 2021), or in the latent space of the transformer (Bao et al., 2021). Most powerful approaches employ a combination of view-invariant and masked image-modeling techniques (Zhou et al., 2021; Oquab et al., 2023). The concept of learning representations by predicting missing information in latent space is formalized by the Joint-Embedding Predictive Architecture (JEPA) (LeCun, 2022), which have been successfully applied across multiple modalities, including audio (Baevski et al., 2022), images (Assran et al., 2023; Bar et al.,), and video (Bardes et al., 2024).

##### Video Models.

Motion cues from videos have inspired many early video pretext tasks. Early methods predicted camera transformations between image pairs (Agrawal et al., 2015) or future frames from ego-motion (Jayaraman and Grauman, 2015). Others brought consecutive frame patches closer in feature space (Wang and Gupta, 2015) or used unsupervised object retrieval for segmentation (Pathak et al., 2017). The rise a large labeled video datasets such as Kinetics (Carreira and Zisserman, 2017) changed the focus of the community towards supervised video models. Early approaches used image sequences with late fusion (Donahue et al., 2015) or 3D convolutions (Tran et al., 2015), but 3D ConvNets are computationally expensive. Recent work improves efficiency with 2D spatial and 1D temporal convolutions (Tran et al., 2018; Xie et al., 2018), dual-pathways (Feichtenhofer et al., 2019), and vision transformers adapted for video (Arnab et al., 2021; Bertasius et al., 2021). Despite rapid progress, supervised learning requires extensive labeled data and may not fully exploit temporal information, and the focus went back to self-supervised learning.

Early self-supervised learning methods focused on temporal order verification (Misra et al., 2016; Xu et al., 2019), contrastive learning (Han et al., 2020; Dave et al., 2022), and future prediction (Han et al., 2019). Recent masked modeling approaches, like VideoMAE (Tong et al., 2022; Feichtenhofer et al., 2022), extend image-based masking to video. Other advances include masked modeling in CLIP space (Li et al., 2023), joint image-video training (OmniMAE (Girdhar et al., 2023)), and architectural innovations such as hierarchical transformers (Ryali et al., 2023) and decoupled encoders/decoders (Gupta et al., 2023). Despite progress, defining optimal pretext tasks and efficient video processing remain open challenges.

Scaling existing approaches, both in terms of data and model size, has demonstrated that generalist video encoders can be learned from extensive observation datasets of videos using self-supervised learning (Carreira et al., 2024; Wang et al., 2023; Rajasegaran et al., 2025). In particular, Joint-Embedding Predictive architectures show promising efficiency gains at large scale compared to generative approaches (Bardes et al., 2024), and open the door to applications in world modeling (Assran et al., 2025). Self-supervised models can also incorporated weak language supervision (Zhao et al., 2024; Wang et al., 2024b; Bolya et al., 2025), unlocking language-based tasks.

##### Learning dense features.

Learning dense features is often achieved through designing local loss functions and objectives, such as leveraging spatio-temporal consistency in videos (Jabri et al., 2020), spatial alignment between image crops (Pinheiro et al., 2020; Bardes et al., 2022), and patch consistency (Yun et al., 2022). Contrastive learning approaches such as DetCon (Hénaff et al., 2021) and ORL (Xie et al., 2021a) use region proposals, while newer methods relax this requirement (Hénaff et al., 2022; Wen et al., 2022). Recent distillation-based methods combine strengths from multiple encoders, such as AM-RADIO (Ranzinger et al., 2024), Perception Encoder (Bolya et al., 2025), and DINOv3 (Siméoni et al., 2025), using objectives like cosine similarity and Gram matrix regularization to improve dense features. Some works focus on post-hoc improvements, including fine-tuning with clustering objectives (Ziegler and Asano, 2022), patch alignment (Salehi et al., 2023), and patch-sorting (Pariza et al., 2025). Others enhance features without fine-tuning, such as STEGO (Hamilton et al., 2022) and feature augmentation (Simoncini et al., 2024).

Beyond playing with the loss function, the standard Vision Transformer (ViT) (Dosovitskiy et al., 2021) can be adapted for dense prediction tasks, Ranftl et al. (2021) introduced the Dense Prediction Transformer (DPT), evolving from their prior CNN-based work on MiDaS (Ranftl et al., 2020). DPT solved the token-to-pixel problem using a "reassemble" operation that converts the 1D ViT sequence into multi-scale 2D feature maps, which are then fused by a convolutional decoder adapted from RefineNet (Lin et al., 2017a). This design, which leverages the global receptive field of the transformer backbone, proved effective for obtaining structural coherence, moving beyond the limitations of purely hierarchical CNNs. The work also catalyzed parallel research, including the development of purely transformer-based decoders like Segmenter (Strudel et al., 2021) and hierarchical transformer backbones like the Swin Transformer (Liu et al., 2021) and the Multiscale Vision Transformer (Fan et al., 2021). DPT architectural framework has proven to be the most influential design for scaling up, serving as the basis for current state-of-the-art foundation models like Depth Anything (Yang et al., 2024).

<a id="section-5"></a>

## 5 Conclusion and Future work

This work demonstrates how Joint-Embedding Predictive Architectures and Self-Supervised Learning from video unlock high-quality dense local features with strong global semantic understanding.
Our key ingredient is a novel deep spatio-temporal self-supervision, composed by a weighted context loss and a multi-level predictor that enables supervision across the intermediate encoder layers.
This design unlocks high-quality dense features that are spatially structured, semantically coherent and temporally consistent, as evidenced by PCA visualizations.
Beyond the training objective, we demonstrate the importance of modality-specific tokenizers, large-scale and balanced image–video data curation, and scaling to ViT-G, which together enable an effective distillation to compact models.
Our V-JEPA 2.1 ViT-G achieves absolute state-of-the-art performance in short-term object interaction anticipation, action anticipation and action recognition, showcasing its excellent predictive and motion understanding capabilities.
Moreover, the dense feature maps achieve linear-probe state-of-the-art performance in monocular depth estimation and strong results in semantic segmentation and video object tracking. We hope these findings encourage further research on predictive physical world modeling.

##### Future work.

Future work will focus on several promising directions. First, scaling along two axes: a) model size, we observe a very positive trend scaling from 1B to 2B and other work such as DINOv3 showed the benefit of scaling to 7B in vision; b) data size, our work on data curation highlighted that video self-supervised learning really benefit from large-scale datasets. Second, this work focus on learning better representation, whereas V-JEPA 2 showed the potential of building world models on top of these representations. Future work in this direction will explore world modeling aspects with the prism of learning dense prediction capabilities (Karypidis et al., 2024; Bojanowski, 2025). Finally, world models with dense understanding and prediction abilities will unlock many applications in robotics and autonomous agents, where a precise estimation of the state down to the pixel level is required, for example navigation in challenging real world environment, or fine-grained manipulation.

## References

- Agrawal et al. (2015)
  Pulkit Agrawal, Joao Carreira, and Jitendra Malik.
  Learning to see by moving.
  In _ICCV_, 2015.
- Arnab et al. (2021)
  Anurag Arnab, Mostafa Dehghani, Georg Heigold, Chen Sun, Mario Lucic, and Cordelia Schmid.
  Vivit: A video vision transformer.
  In _ICCV_, 2021.
- Assran et al. (2023)
  Mahmoud Assran, Quentin Duval, Ishan Misra, Piotr Bojanowski, Pascal Vincent, Michael Rabbat, Yann LeCun, and Nicolas Ballas.
  Self-supervised learning from images with a joint-embedding predictive architecture.
  In _Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition_, pages 15619–15629, 2023.
- Assran et al. (2025)
  Mido Assran, Adrien Bardes, David Fan, Quentin Garrido, Russell Howes, Matthew Muckley, Ammar Rizvi, Claire Roberts, Koustuv Sinha, Artem Zholus, et al.
  V-jepa 2: Self-supervised video models enable understanding, prediction and planning.
  _arXiv preprint arXiv:2506.09985_, 2025.
- Baevski et al. (2022)
  Alexei Baevski, Wei-Ning Hsu, Qiantong Xu, Arun Babu, Jiatao Gu, and Michael Auli.
  Data2vec: A general framework for self-supervised learning in speech, vision and language.
  _arXiv preprint arXiv:2202.03555_, 2022.
- Balestriero and LeCun (2025)
  Randall Balestriero and Yann LeCun.
  Lejepa: Provable and scalable self-supervised learning without the heuristics.
  _arXiv preprint arXiv:2511.08544_, 2025.
- Bao et al. (2021)
  Hangbo Bao, Li Dong, and Furu Wei.
  Beit: Bert pre-training of image transformers.
  _arXiv preprint arXiv:2106.08254_, 2021.
- (8)
  Amir Bar, Florian Bordes, Assaf Shocher, Mido Assran, Pascal Vincent, Nicolas Ballas, Trevor Darrell, Amir Globerson, and Yann LeCun.
  Stochastic positional embeddings improve masked image modeling.
  In _Forty-first International Conference on Machine Learning_.
- Bar et al. (2025)
  Amir Bar, Gaoyue Zhou, Danny Tran, Trevor Darrell, and Yann LeCun.
  Navigation world models.
  In _Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR)_, pages 15791–15801, June 2025.
- Bardes et al. (2021)
  Adrien Bardes, Jean Ponce, and Yann LeCun.
  Vicreg: Variance-invariance-covariance regularization for self-supervised learning.
  _arXiv preprint arXiv:2105.04906_, 2021.
- Bardes et al. (2022)
  Adrien Bardes, Jean Ponce, and Yann LeCun.
  Vicregl: Self-supervised learning of local visual features.
  _NeurIPS_, 2022.
- Bardes et al. (2024)
  Adrien Bardes, Quentin Garrido, Jean Ponce, Xinlei Chen, Michael Rabbat, Yann LeCun, Mahmoud Assran, and Nicolas Ballas.
  Revisiting feature prediction for learning visual representations from video.
  _arXiv preprint arXiv:2404.08471_, 2024.
- Bertasius et al. (2021)
  Gedas Bertasius, Heng Wang, and Lorenzo Torresani.
  Is space-time attention all you need for video understanding?
  In _ICML_, 2021.
- Bojanowski (2025)
  Federico Baldassarre Marc Szafraniec Basile Terver Vasil Khalidov Francisco Massa Yann LeCun Patrick Labatut Maximilian Seitzer Piotr Bojanowski.
  Back to the features: Dino as a foundation for video world models.
  _arXiv preprint arXiv:2507.19468_, 2025.
- Bolya et al. (2025)
  Daniel Bolya, Po-Yao Huang, Peize Sun, Jang Hyun Cho, Andrea Madotto, Chen Wei, Tengyu Ma, Jiale Zhi, Jathushan Rajasegaran, Hanoona Rasheed, et al.
  Perception encoder: The best visual embeddings are not at the output of the network.
  _arXiv preprint arXiv:2504.13181_, 2025.
- Cai et al. (2024)
  Mu Cai, Reuben Tan, Jianrui Zhang, Bocheng Zou, Kai Zhang, Feng Yao, Fangrui Zhu, Jing Gu, Yiwu Zhong, Yuzhang Shang, Yao Dou, Jaden Park, Jianfeng Gao, Yong Jae Lee, and Jianwei Yang.
  Temporalbench: Benchmarking fine-grained temporal understanding for multimodal video models.
  _arXiv preprint arXiv:2410.10818_, 2024.
- Caron et al. (2018)
  Mathilde Caron, Piotr Bojanowski, Armand Joulin, and Matthijs Douze.
  Deep clustering for unsupervised learning.
  In _ECCV_, 2018.
- Caron et al. (2020)
  Mathilde Caron, Ishan Misra, Julien Mairal, Priya Goyal, Piotr Bojanowski, and Armand Joulin.
  Unsupervised learning of visual features by contrasting cluster assignments.
  In _NeurIPS_, 2020.
- Caron et al. (2021)
  Mathilde Caron, Hugo Touvron, Ishan Misra, Herve Jegou, and Julien Mairal Piotr Bojanowski Armand Joulin.
  Emerging properties in self-supervised vision transformers.
  In _ICCV_, 2021.
- Carreira et al. (2019)
  Joao Carreira, Eric Noland, Chloe Hillier, and Andrew Zisserman.
  A short note on the kinetics-700 human action dataset.
  _arXiv preprint arXiv:1907.06987_, 2019.
- Carreira and Zisserman (2017)
  João Carreira and Andrew Zisserman.
  Quo vadis, action recognition? a new model and the kinetics dataset.
  In _CVPR_, 2017.
- Carreira et al. (2024)
  João Carreira, Dilara Gokay, Michael King, Chuhan Zhang, Ignacio Rocco, Aravindh Mahendran, Thomas Albert Keck, Joseph Heyward, Skanda Koppula, Etienne Pot, Goker Erdogan, Yana Hasson, Yi Yang, Klaus Greff, Guillaume Le Moing, Sjoerd van Steenkiste, Daniel Zoran, Drew A. Hudson, Pedro Vélez, Luisa Polanía, Luke Friedman, Chris Duvarney, Ross Goroshin, Kelsey Allen, Jacob Walker, Rishabh Kabra, Eric Aboussouan, Jennifer Sun, Thomas Kipf, Carl Doersch, Viorica Pătrăucean, Dima Damen, Pauline Luc, Mehdi S. M. Sajjadi, and Andrew Zisserman.
  Scaling 4d representations.
  _arXiv preprint arXiv:2412.15212_, 2024.
- Chen et al. (2020)
  Ting Chen, Simon Kornblith, Mohammad Norouzi, and Geoffrey E. Hinton.
  A simple framework for contrastive learning of visual representations.
  In _ICML_, 2020.
- Chen and He (2020)
  Xinlei Chen and Kaiming He.
  Exploring simple siamese representation learning.
  In _CVPR_, 2020.
- Chen et al. (2021)
  Xinlei Chen, Saining Xie, and Kaiming He.
  An empirical study of training self-supervised vision transformers.
  In _ICCV_, 2021.
- Chen et al. (2024)
  Zhe Chen, Weiyun Wang, Yue Cao, Yangzhou Liu, Zhangwei Gao, Erfei Cui, Jinguo Zhu, Shenglong Ye, Hao Tian, Zhaoyang Liu, Lixin Gu, Xuehui Wang, Qingyun Li, Yimin Ren, Zixuan Chen, Jiapeng Luo, Jiahao Wang, Tan Jiang, Bo Wang, Conghui He, Botian Shi, Xingcheng Zhang, Han Lv, Yi Wang, Wenqi Shao, Pei Chu, Zhongying Tu, Tong He, Zhiyong Wu, Huipeng Deng, Jiaye Ge, Kai Chen, Kaipeng Zhang, Limin Wang, Min Dou, Lewei Lu, Xizhou Zhu, Tong Lu, Dahua Lin, Yu Qiao, Jifeng Dai, and Wenhai Wang.
  Expanding performance boundaries of open-source multimodal models with model, data, and test-time scaling.
  _arXiv preprint arXiv:2412.05271_, 2024.
- Cho et al. (2025)
  Jang Hyun Cho, Andrea Madotto, Effrosyni Mavroudi, Triantafyllos Afouras, Tushar Nagarajan, Muhammad Maaz, Yale Song, Tengyu Ma, Shuming Hu, Suyog Jain, Miguel Martin, Huiyu Wang, Hanoona Rasheed, Peize Sun, Po-Yao Huang, Daniel Bolya, Nikhila Ravi, Shashank Jain, Tammy Stark, Shane Moon, Babak Damavandi, Vivian Lee, Andrew Westbury, Salman Khan, Philipp Krähenbühl, Piotr Dollár, Lorenzo Torresani, Kristen Grauman, and Christoph Feichtenhofer.
  Perceptionlm: Open-access data and models for detailed visual understanding.
  _arXiv preprint arXiv:2504.13180_, 2025.
- Cordts et al. (2016)
  Marius Cordts, Mohamed Omran, Sebastian Ramos, Timo Rehfeld, Markus Enzweiler, Rodrigo Benenson, Uwe Franke, Stefan Roth, and Bernt Schiele.
  The cityscapes dataset for semantic urban scene understanding.
  In _Proceedings of the IEEE conference on computer vision and pattern recognition_, pages 3213–3223, 2016.
- Damen et al. (2022)
  Dima Damen, Hazel Doughty, Giovanni Maria Farinella, Antonino Furnari, Jian Ma, Evangelos Kazakos, Davide Moltisanti, Jonathan Munro, Toby Perrett, Will Price, and Michael Wray.
  Rescaling egocentric vision: Collection, pipeline and challenges for epic-kitchens-100.
  _International Journal of Computer Vision (IJCV)_, 2022.
- Darcet et al. (2023)
  Timothée Darcet, Maxime Oquab, Julien Mairal, and Piotr Bojanowski.
  Vision transformers need registers.
  _arXiv preprint arXiv:2309.16588_, 2023.
- Dave et al. (2022)
  Ishan Dave, Rohit Gupta, Mamshad Nayeem Rizve, and Mubarak Shah.
  Tclr: Temporal contrastive learning for video representation.
  _Computer Vision and Image Understanding_, 2022.
- Deng et al. (2009)
  Jia Deng, Wei Dong, Richard Socher, Li-Jia Li, Kai Li, and Li Fei-Fei.
  Imagenet: A large-scale hierarchical image database.
  In _2009 IEEE conference on computer vision and pattern recognition_, pages 248–255. Ieee, 2009.
- Doersch et al. (2015)
  Carl Doersch, Abhinav Gupta, and Alexei A. Efros.
  Unsupervised visual representation learning by context.
  In _ICCV_, 2015.
- Donahue et al. (2015)
  Jeff Donahue, Lisa Anne Hendricks, Sergio Guadarrama, Marcus Rohrbach, Subhashini Venugopalan, and Kate Saenko.
  Long-term recurrent convolutional networks for visual recognition and description.
  In _CVPR_, 2015.
- Dosovitskiy (2020)
  Alexey Dosovitskiy.
  An image is worth 16x16 words: Transformers for image recognition at scale.
  _arXiv preprint arXiv:2010.11929_, 2020.
- Dosovitskiy et al. (2021)
  Alexey Dosovitskiy, Lucas Beyer, Alexander Kolesnikov, Dirk Weissenborn, Xiaohua Zhai, Thomas Unterthiner, Mohammad Dehghani, Matthias Minderer, Georg Heigold, Sylvain Gelly, Jakob Uszkoreit, and Neil Houlsby.
  An image is worth 16x16 words: Transformers for image recognition at scale.
  In _ICLR_, 2021.
- Everingham et al. (2015)
  Mark Everingham, SM Ali Eslami, Luc Van Gool, Christopher KI Williams, John Winn, and Andrew Zisserman.
  The pascal visual object classes challenge: A retrospective.
  _International journal of computer vision_, 111(1):98–136, 2015.
- Fan et al. (2025)
  David Fan, Shengbang Tong, Jiachen Zhu, Koustuv Sinha, Zhuang Liu, Xinlei Chen, Michael Rabbat, Nicolas Ballas, Yann LeCun, Amir Bar, and Saining Xie.
  Scaling language-free visual representation learning.
  _arXiv preprint arXiv:2504.01017_, 2025.
- Fan et al. (2021)
  Haoqi Fan, Bo Xiong, Karttikeya Mangalam, Yanghao Li, Zhicheng Yan, and Jitendra Malik.
  Multiscale vision transformers.
  In _ICCV_, 2021.
- Feichtenhofer et al. (2019)
  Christoph Feichtenhofer, Haoqi Fan, Jitendra Malik, and Kaiming He.
  Slowfast networks for video recognition.
  In _ICCV_, 2019.
- Feichtenhofer et al. (2022)
  Christoph Feichtenhofer, Haoqi Fan, Yanghao Li, and Kaiming He.
  Masked autoencoders as spatiotemporal learners.
  In _NeurIPS_, 2022.
- Garrido et al. (2025)
  Quentin Garrido, Nicolas Ballas, Mahmoud Assran, Adrien Bardes, Laurent Najman, Michael Rabbat, Emmanuel Dupoux, and Yann LeCun.
  Intuitive physics understanding emerges from self-supervised pretraining on natural videos.
  _arXiv preprint arXiv:2502.11831_, 2025.
- Geiger et al. (2013a)
  Andreas Geiger, Philip Lenz, Christoph Stiller, and Raquel Urtasun.
  Vision meets robotics: The kitti dataset.
  In _The International Journal of Robotics Research_, 2013a.
- Geiger et al. (2013b)
  Andreas Geiger, Philip Lenz, Christoph Stiller, and Raquel Urtasun.
  Vision meets robotics: The kitti dataset.
  _The international journal of robotics research_, 32(11):1231–1237, 2013b.
- Gidaris et al. (2018)
  S. Gidaris, P. Singh, and N. Komodakis.
  Unsupervised representation learning by predicting image rotations.
  In _ICLR_, 2018.
- Girdhar et al. (2023)
  Rohit Girdhar, Alaaeldin El-Nouby, Mannat Singh, Kalyan Vasudev Alwala, Armand Joulin, and Ishan Misra.
  Omnimae: Single model masked pretraining on images and videos.
  In _CVPR_, 2023.
- Girshick (2015)
  Ross Girshick.
  Fast r-cnn.
  In _Proceedings of the IEEE international conference on computer vision_, pages 1440–1448, 2015.
- Goyal et al. (2017)
  Raghav Goyal, Samira Ebrahimi Kahou, Vincent Michalski, Joanna Materzynska, Susanne Westphal, Heuna Kim, Valentin Haenel, Ingo Fruend, Peter Yianilos, Moritz Mueller-Freitag, et al.
  The" something something" video database for learning and evaluating visual common sense.
  In _Proceedings of the IEEE international conference on computer vision_, pages 5842–5850, 2017.
- Grauman et al. (2022)
  Kristen Grauman, Andrew Westbury, Eugene Byrne, Zachary Chavis, Antonino Furnari, Rohit Girdhar, Jackson Hamburger, Hao Jiang, Miao Liu, Xingyu Liu, et al.
  Ego4d: Around the world in 3,000 hours of egocentric video.
  In _Proceedings of the IEEE/CVF conference on computer vision and pattern recognition_, pages 18995–19012, 2022.
- Grill et al. (2020a)
  Jean-Bastien Grill, Florian Strub, Florent Altché, Corentin Tallec, Pierre Richemond, Elena Buchatskaya, Carl Doersch, Bernardo Avila Pires, Zhaohan Guo, Mohammad Gheshlaghi Azar, et al.
  Bootstrap your own latent-a new approach to self-supervised learning.
  _Advances in neural information processing systems_, 33:21271–21284, 2020a.
- Grill et al. (2020b)
  Jean-Bastien Grill, Florian Strub, Florent Altché, Corentin Tallec, Pierre H. Richemond, Elena Buchatskaya, Carl Doersch, Bernardo Avila Pires, Zhaohan Daniel Guo, Mohammad Gheshlaghi Azar, Bilal Piot, Koray Kavukcuoglu, Rémi Munos, and Michal Valko.
  Bootstrap your own latent: A new approach to self-supervised learning.
  In _NeurIPS_, 2020b.
- Gupta et al. (2023)
  Ankush Gupta, Viorica Patraucean, Lucas Smaira, Larisa Markeeva, Menglin Chen, Teli He, Dylan Banarse, Antoine Miech, Alex Frechette, Raphael Koster, et al.
  Decoupled video coding with decoupled video prediction.
  _arXiv preprint arXiv:2307.13532_, 2023.
- Ha and Schmidhuber (2018)
  David Ha and Jürgen Schmidhuber.
  World models.
  _arXiv preprint arXiv:1803.10122_, 2(3), 2018.
- Hamilton et al. (2022)
  Mark Hamilton, Zhoutong Zhang, Bharath Hariharan, Noah Snavely, and William T. Freeman.
  Unsupervised semantic segmentation by distilling feature correspondences.
  In _ICLR_, 2022.
- Han et al. (2019)
  Tengda Han, Weidi Xie, and Andrew Zisserman.
  Video representation learning by dense predictive coding.
  In _Workshop on Large Scale Holistic Video Understanding, ICCV_, 2019.
- Han et al. (2020)
  Tengda Han, Weidi Xie, and Andrew Zisserman.
  Self-supervised co-training for video representation learning.
  In _NeurIPS_, 2020.
- He et al. (2020)
  Kaiming He, Haoqi Fan, Yuxin Wu, Saining Xie, and Ross Girshick.
  Momentum contrast for unsupervised visual representation learning.
  In _CVPR_, 2020.
- Hinton et al. (2015)
  Geoffrey Hinton, Oriol Vinyals, and Jeff Dean.
  Distilling the knowledge in a neural network.
  _arXiv preprint arXiv:1503.02531_, 2015.
- Ho et al. (2020)
  Jonathan Ho, Ajay Jain, and Pieter Abbeel.
  Denoising diffusion probabilistic models.
  _Advances in neural information processing systems_, 33:6840–6851, 2020.
- Hénaff et al. (2019)
  Olivier J. Hénaff, Aravind Srinivas, Jeffrey De Fauw, Ali Razavi, Carl Doersch, S. M. Ali Eslami, and Aäron van den Oord.
  Data-efficient image recognition with contrastive predictive coding.
  In _ICML_, 2019.
- Hénaff et al. (2021)
  Olivier J. Hénaff, Skanda Koppula, Jean-Baptiste Alayrac, Aaron van den Oord, Oriol Vinyals, and João Carreira.
  Efficient visual pretraining with contrastive detection.
  _arXiv preprint arXiv:2103.10957_, 2021.
- Hénaff et al. (2022)
  Olivier J. Hénaff, Skanda Koppula, Evan Shelhamer, Daniel Zoran, Andrew Jaegle, Andrew Zisserman, João Carreira, and Relja Arandjelović.
  Object discovery and representation networks.
  In _ECCV_, 2022.
- Jabri et al. (2020)
  Allan Jabri, Andrew Owens, and Alexei Efros.
  Space-time correspondence as a contrastive random walk.
  _Advances in neural information processing systems_, 33:19545–19560, 2020.
- Jayaraman and Grauman (2015)
  D. Jayaraman and K. Grauman.
  Learning image representations tied to ego-motion.
  In _ICCV_, 2015.
- Karypidis et al. (2024)
  Efstathios Karypidis, Ioannis Kakogeorgiou, Spyros Gidaris, , and Nikos Komodakis.
  Dino-foresight: Looking into the future with dino.
  _arXiv preprint arXiv:2412.11673_, 2024.
- Kay et al. (2017)
  Will Kay, Joao Carreira, Karen Simonyan, Brian Zhang, Chloe Hillier, Sudheendra Vijayanarasimhan, Fabio Viola, Tim Green, Trevor Back, Paul Natsev, et al.
  The kinetics human action video dataset.
  _arXiv preprint arXiv:1705.06950_, 2017.
- Khazatsky et al. (2024)
  Alexander Khazatsky, Karl Pertsch, Suraj Nair, Ashwin Balakrishna, Sudeep Dasari, Siddharth Karamcheti, Soroush Nasiriany, Mohan Kumar Srirama, Lawrence Yunliang Chen, Kirsty Ellis, Peter David Fagan, Joey Hejna, Masha Itkina, Marion Lepert, Yecheng Jason Ma, Patrick Tree Miller, Jimmy Wu, Suneel Belkhale, Shivin Dass, Huy Ha, Arhan Jain, Abraham Lee, Youngwoon Lee, Marius Memmel, Sungjae Park, Ilija Radosavovic, Kaiyuan Wang, Albert Zhan, Kevin Black, Cheng Chi, Kyle Beltran Hatch, Shan Lin, Jingpei Lu, Jean Mercat, Abdul Rehman, Pannag R Sanketi, Archit Sharma, Cody Simpson, Quan Vuong, Homer Rich Walke, Blake Wulfe, Ted Xiao, Jonathan Heewon Yang, Arefeh Yavary, Tony Z. Zhao, Christopher Agia, Rohan Baijal, Mateo Guaman Castro, Daphne Chen, Qiuyu Chen, Trinity Chung, Jaimyn Drake, Ethan Paul Foster, Jensen Gao, Vitor Guizilini, David Antonio Herrera, Minho Heo, Kyle Hsu, Jiaheng Hu, Muhammad Zubair Irshad, Donovon Jackson, Charlotte Le, Yunshuang Li, Kevin Lin, Roy Lin, Zehan Ma, Abhiram Maddukuri, Suvir
  Mirchandani, Daniel Morton, Tony Nguyen, Abigail O’Neill, Rosario Scalise, Derick Seale, Victor Son, Stephen Tian, Emi Tran, Andrew E. Wang, Yilin Wu, Annie Xie, Jingyun Yang, Patrick Yin, Yunchu Zhang, Osbert Bastani, Glen Berseth, Jeannette Bohg, Ken Goldberg, Abhinav Gupta, Abhishek Gupta, Dinesh Jayaraman, Joseph J Lim, Jitendra Malik, Roberto Martín-Martín, Subramanian Ramamoorthy, Dorsa Sadigh, Shuran Song, Jiajun Wu, Michael C. Yip, Yuke Zhu, Thomas Kollar, Sergey Levine, and Chelsea Finn.
  Droid: A large-scale in-the-wild robot manipulation dataset.
  _arXiv preprint arXiv:2403.12945_, 2024.
- Krojer et al. (2024)
  Benno Krojer, Mojtaba Komeili, Candace Ross, Quentin Garrido, Koustuv Sinha, Nicolas Ballas, and Mido Assran.
  A shortcut-aware video-qa benchmark for physical understanding via minimal video pairs.
  _preprint_, 2024.
- Lamdouar et al. (2020)
  Hala Lamdouar, Charig Yang, Weidi Xie, and Andrew Zisserman.
  Betrayed by motion: Camouflaged object discovery via motion segmentation.
  In _Proceedings of the Asian conference on computer vision_, 2020.
- LeCun (2022)
  Yann LeCun.
  A path towards autonomous machine intelligence version 0.9. 2, 2022-06-27.
  _Open Review_, 62(1):1–62, 2022.
- Li et al. (2023)
  Kai Li, Yulin Liu, Lei Li, et al.
  Unmasked teacher: Towards training-efficient video foundation models.
  _arXiv preprint arXiv:2303.16035_, 2023.
- Li et al. (2024)
  Kunchang Li, Yali Wang, Yinan He, Yizhuo Li, Yi Wang, Yi Liu, Zun Wang, Jilan Xu, Guo Chen, Ping Luo, Limin Wang, and Yu Qiao.
  Mvbench: A comprehensive multi-modal video understanding benchmark.
  In _Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition_, pages 22195–22206, 2024.
- Li and He (2025)
  Tianhong Li and Kaiming He.
  Back to basics: Let denoising generative models denoise.
  _arXiv preprint arXiv:2511.13720_, 2025.
- Li et al. (2018)
  Yingwei Li, Yi Li, and Nuno Vasconcelos.
  Resound: Towards action recognition without representation bias.
  In _Proceedings of the European conference on computer vision (ECCV)_, pages 513–528, 2018.
- Lin et al. (2017a)
  Guoliang Lin, Anton Milan, Chunhua Shen, and Ian Reid.
  Refinenet: Multi-path refinement networks for high-resolution semantic segmentation.
  In _CVPR_, 2017a.
- Lin et al. (2017b)
  Tsung-Yi Lin, Priya Goyal, Ross Girshick, Kaiming He, and Piotr Dollár.
  Focal loss for dense object detection.
  In _Proceedings of the IEEE international conference on computer vision_, pages 2980–2988, 2017b.
- Liu et al. (2024)
  Yuanxin Liu, Shicheng Li, Yi Liu, Yuxiang Wang, Shuhuai Ren, Lei Li, Sishuo Chen, Xu Sun, and Lu Hou.
  TempCompass: Do video LLMs really understand videos?
  _arXiv preprint arXiv:2403.00476_, 2024.
- Liu et al. (2021)
  Ze Liu, Yutong Lin, Yue Cao, Han Hu, Yixuan Wei, Zheng Zhang, Stephen Lin, and Baining Guo.
  Swin transformer: Hierarchical vision transformer using shifted windows.
  In _ICCV_, 2021.
- Miech et al. (2019)
  Antoine Miech, Dimitri Zhukov, Jean-Baptiste Alayrac, Makarand Tapaswi, Ivan Laptev, and Josef Sivic.
  Howto100m: Learning a text-video embedding by watching hundred million narrated video clips.
  In _Proceedings of the IEEE/CVF international conference on computer vision_, pages 2630–2640, 2019.
- Misra and Maaten (2020)
  Ishan Misra and Laurens van der Maaten.
  Self-supervised learning of pretext-invariant representations.
  In _CVPR_, 2020.
- Misra et al. (2016)
  Ishan Misra, C. Lawrence Zitnick, and Martial Hebert.
  Shuffle and learn: Unsupervised learning using temporal order verification.
  In _ECCV_, 2016.
- Mittal et al. (2024)
  Himangi Mittal, Nakul Agarwal, Shao-Yuan Lo, and Kwonjoon Lee.
  Can’t make an omelette without breaking some eggs: Plausible action anticipation using large video-language models.
  In _Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition_, pages 18580–18590, 2024.
- Mo and Tong (2024)
  Shentong Mo and Shengbang Tong.
  Connecting joint-embedding predictive architecture with contrastive self-supervised learning.
  _Advances in neural information processing systems_, 37:2348–2377, 2024.
- Mur-Labadia et al. (2024)
  Lorenzo Mur-Labadia, Ruben Martinez-Cantin, Jose J Guerrero, Giovanni Maria Farinella, and Antonino Furnari.
  Aff-ttention! affordances and attention models for short-term object interaction anticipation.
  In _European Conference on Computer Vision_, pages 167–184. Springer, 2024.
- Noroozi and Favaro (2016)
  M. Noroozi and P. Favaro.
  Unsupervised learning of visual representations by solving jigsaw puzzles.
  In _ECCV_, 2016.
- Oquab et al. (2023)
  Maxime Oquab, Timothée Darcet, Théo Moutakanni, Huy Vo, Marc Szafraniec, Vasil Khalidov, Pierre Fernandez, Daniel Haziza, Francisco Massa, Alaaeldin El-Nouby, et al.
  Dinov2: Learning robust visual features without supervision.
  _arXiv preprint arXiv:2304.07193_, 2023.
- Pariza et al. (2025)
  Valentinos Pariza, Mohammadreza Salehi, Gertjan J. Burghouts, Francesco Locatello, and Yuki M. Asano.
  Near, far: Patch-ordering enhances vision foundation models’ scene understanding.
  In _ICLR_, 2025.
- Pathak et al. (2016)
  Deepak Pathak, Philipp Krahenbuhl, Jeff Donahue, Trevor Darrell, and Alexei A. Efros.
  Context encoders: Feature learning by inpainting.
  In _CVPR_, 2016.
- Pathak et al. (2017)
  Deepak Pathak, Ross Girshick, Piotr Dollár, Trevor Darrell, and Bharath Hariharan.
  Learning features by watching objects move.
  In _CVPR_, 2017.
- Perazzi et al. (2016)
  Federico Perazzi, Jordi Pont-Tuset, Brian McWilliams, Luc Van Gool, Markus Gross, and Alexander Sorkine-Hornung.
  A benchmark dataset and evaluation methodology for video object segmentation.
  In _Proceedings of the IEEE conference on computer vision and pattern recognition_, pages 724–732, 2016.
- Pinheiro et al. (2020)
  Pedro O. Pinheiro, Amjad Almahairi, Ryan Y. Benmaleck, Florian Golemo, and Aaron Courville.
  Unsupervised learning of dense visual representations.
  In _NeurIPS_, 2020.
- Pont-Tuset et al. (2017)
  Jordi Pont-Tuset, Federico Perazzi, Sergi Caelles, Pablo Arbeláez, Alex Sorkine-Hornung, and Luc Van Gool.
  The 2017 davis challenge on video object segmentation.
  _arXiv preprint arXiv:1704.00675_, 2017.
- Pătrăucean et al. (2023)
  Viorica Pătrăucean, Lucas Smaira, Ankush Gupta, Adrià Recasens Continente, Larisa Markeeva, Dylan Banarse, Skanda Koppula, Joseph Heyward, Mateusz Malinowski, Yi Yang, Carl Doersch, Tatiana Matejovicova, Yury Sulsky, Antoine Miech, Alex Frechette, Hanna Klimczak, Raphael Koster, Junlin Zhang, Stephanie Winkler, Yusuf Aytar, Simon Osindero, Dima Damen, Andrew Zisserman, and João Carreira.
  Perception test: A diagnostic benchmark for multimodal video models.
  _Advances in Neural Information Processing Systems_, 36:42748–42761, 2023.
- Qwen Team et al. (2025)
  Qwen Team, Shuai Bai, Keqin Chen, Xuejing Liu, Jialin Wang, Wenbin Ge, Sibo Song, Kai Dang, Peng Wang, Shijie Wang, Jun Tang, Humen Zhong, Yuanzhi Zhu, Mingkun Yang, Zhaohai Li, Jianqiang Wan, Pengfei Wang, Wei Ding, Zheren Fu, Yiheng Xu, Jiabo Ye, Xi Zhang, Tianbao Xie, Zesen Cheng, Hang Zhang, Zhibo Yang, Haiyang Xu, Junyang Lin, An Yang, Binyuan Hui, Bowen Yu, Chen Cheng, Dayiheng Liu, Fan Hong, Fei Huang, Jiawei Liu, Jin Xu, Jianhong Tu, Jianyuan Zeng, Jie Zhang, Jinkai Wang, Jianwei Zhang, Jingren Zhou, Kexin Yang, Mei Li, Ming Yan, Na Ni, Rui Men, Songtao Jiang, Xiaodong Deng, Xiaoming Huang, Ximing Zhou, Xingzhang Ren, Yang Fan, Yichang Zhang, Yikai Zhu, Yuqiong Liu, and Zhifang Guo.
  Qwen2.5-vl technical report.
  _arXiv preprint arXiv:2502.13923_, 2025.
- Ragusa et al. (2023)
  Francesco Ragusa, Giovanni Maria Farinella, and Antonino Furnari.
  Stillfast: An end-to-end approach for short-term object interaction anticipation.
  In _Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR) Workshops_, 2023.
- Rajasegaran et al. (2025)
  Jathushan Rajasegaran, Ilija Radosavovic, Rahul Ravishankar, Yossi Gandelsman, Christoph Feichtenhofer, and Jitendra Malik.
  An empirical study of autoregressive pre-training from videos.
  _arXiv preprint arXiv:2501.05453_, 2025.
- Ranftl et al. (2020)
  René Ranftl, Katrin Lasinger, and Vladlen Koltun.
  Toward robust monocular depth estimation: Mixing datasets for zero-shot cross-dataset transfer.
  In _ECCV_, 2020.
  Published in TPAMI in 2022.
- Ranftl et al. (2021)
  René Ranftl, Alexey Bochkovskiy, and Vladlen Koltun.
  Vision transformers for dense prediction.
  In _ICCV_, 2021.
- Ranzinger et al. (2024)
  Mike Ranzinger, Greg Heinrich, Jan Kautz, and Pavlo Molchanov.
  Am-radio: Agglomerative vision foundation model reduce all domains into one.
  In _CVPR_, 2024.
- Rombach et al. (2022)
  Robin Rombach, Andreas Blattmann, Dominik Lorenz, Patrick Esser, and Björn Ommer.
  High-resolution image synthesis with latent diffusion models.
  In _Proceedings of the IEEE/CVF conference on computer vision and pattern recognition_, pages 10684–10695, 2022.
- Roy et al. (2024)
  Debaditya Roy, Ramanathan Rajendiran, and Basura Fernando.
  Interaction region visual transformer for egocentric action anticipation.
  In _Proceedings of the IEEE/CVF Winter Conference on Applications of Computer Vision_, pages 6740–6750, 2024.
- Rubinstein (1997)
  Reuven Y. Rubinstein.
  Optimization of computer simulation models with rare events.
  _European Journal of Operations Research_, 99:89–112, 1997.
- Ryali et al. (2023)
  Chaitanya Ryali, Yuan-Ting Hu, Daniel Bolya, Chen Wei, Haoqi Fan, Po-Yao Huang, Vaibhav Aggarwal, Arkabandhu Chowdhury, Omid Poursaeed, Judy Hoffman, et al.
  Hiera: A hierarchical vision transformer without the bells-and-whistles.
  _arXiv preprint arXiv:2306.00989_, 2023.
- Salehi et al. (2023)
  Mohammadreza Salehi, Efstratios Gavves, Cees G. M. Snoek, and Yuki M. Asano.
  Time does tell: Self-supervised time-tuning of dense image representations.
  In _ICCV_, 2023.
- Shangguan et al. (2024)
  Ziyao Shangguan, Chuhan Li, Yuxuan Ding, Yanan Zheng, Yilun Zhao, Tesca Fitzgerald, and Arman Cohan.
  Tomato: Assessing visual temporal reasoning capabilities in multimodal foundation models.
  _arXiv preprint arXiv:2410.23266_, 2024.
- Silberman et al. (2012a)
  Nathan Silberman, Derek Hoiem, Pushmeet Kohli, and Rob Fergus.
  Indoor segmentation and support inference from rgbd images.
  In _European conference on computer vision_, pages 746–760. Springer, 2012a.
- Silberman et al. (2012b)
  Nathan Silberman, Derek Hoiem, Pushmeet Kohli, and Rob Fergus.
  Indoor segmentation and support inference from rgbd images.
  In _ECCV_, 2012b.
- Siméoni et al. (2025)
  Oriane Siméoni, Huy V Vo, Maximilian Seitzer, Federico Baldassarre, Maxime Oquab, Cijo Jose, Vasil Khalidov, Marc Szafraniec, Seungeun Yi, Michaël Ramamonjisoa, et al.
  Dinov3.
  _arXiv preprint arXiv:2508.10104_, 2025.
- Simoncini et al. (2024)
  Walter Simoncini, Andrei Bursuc, Spyridon Gidaris, and Yuki Asano.
  No train, all gain: Self-supervised gradients improve deep frozen representations.
  In _NeurIPS_, 2024.
- Song et al. (2020)
  Jiaming Song, Chenlin Meng, and Stefano Ermon.
  Denoising diffusion implicit models.
  _arXiv preprint arXiv:2010.02502_, 2020.
- Strudel et al. (2021)
  Robin Strudel, Ricardo Garcia, Ivan Laptev, and Cordelia Schmid.
  Segmenter: Transformer for semantic segmentation.
  In _ICCV_, 2021.
- Sutton (1981)
  Richard S Sutton.
  An adaptive network that constructs and uses and internal model of its world.
  _Cognition and Brain Theory_, 4(3):217–246, 1981.
- Thakur et al. (2023)
  Sanket Thakur, Cigdem Beyan, Pietro Morerio, Vittorio Murino, and Alessio Del Bue.
  Guided attention for next active object@ ego4d sta challenge.
  _arXiv preprint arXiv:2305.16066_, 2023.
- Tong et al. (2022)
  Zhan Tong, Yibing Song, Jue Wang, and Limin Wang.
  Videomae: Masked autoencoders are data-efficient learners for self-supervised video pre-training.
  _Advances in neural information processing systems_, 35:10078–10093, 2022.
- Tran et al. (2015)
  Du Tran, Lubomir Bourdev, Rob Fergus, Lorenzo Torresani, and Manohar Paluri.
  Learning spatiotemporal features with 3d convolutional networks.
  In _ICCV_, 2015.
- Tran et al. (2018)
  Du Tran, Heng Wang, Lorenzo Torresani, Jamie Ray, Yann LeCun, and Manohar Paluri.
  Look at spatiotemporal convolutions for action recognition.
  In _CVPR_, 2018.
- Tschannen et al. (2025)
  Michael Tschannen, Alexey Gritsenko, Xiao Wang, Muhammad Ferjad Naeem, Ibrahim Alabdulmohsin, Nikhil Parthasarathy, Talfan Evans, Lucas Beyer, Ye Xia, Basil Mustafa, et al.
  Siglip 2: Multilingual vision-language encoders with improved semantic understanding, localization, and dense features.
  _arXiv preprint arXiv:2502.14786_, 2025.
- Wang et al. (2023)
  Limin Wang, Bingkun Huang, Zhiyu Zhao, Zhan Tong, Yinan He, Yi Wang, Yali Wang, and Yu Qiao.
  Videomae v2: Scaling video masked autoencoders with dual masking.
  In _Proceedings of the IEEE/CVF conference on computer vision and pattern recognition_, pages 14549–14560, 2023.
- Wang et al. (2024a)
  Peng Wang, Shuai Bai, Sinan Tan, Shijie Wang, Zhihao Fan, Jinze Bai, Keqin Chen, Xuejing Liu, Jialin Wang, Wenbin Ge, Yang Fan, Kai Dang, Mengfei Du, Xuancheng Ren, Rui Men, Dayiheng Liu, Chang Zhou, Jingren Zhou, and Junyang Lin.
  Qwen2-vl: Enhancing vision-language model’s perception of the world at any resolution.
  _arXiv preprint arXiv:2409.12191_, 2024a.
- Wang and Gupta (2015)
  Xiaolong Wang and Abhinav Gupta.
  Unsupervised learning of visual representations using videos.
  In _ICCV_, 2015.
- Wang et al. (2024b)
  Yi Wang, Kunchang Li, Xinhao Li, Jiashuo Yu, Yinan He, Guo Chen, Baoqi Pei, Rongkun Zheng, Zun Wang, Yansong Shi, et al.
  Internvideo2: Scaling foundation models for multimodal video understanding.
  In _European Conference on Computer Vision_, pages 396–416. Springer, 2024b.
- Wei et al. (2021)
  Chen Wei, Haoqi Fan, Saining Xie, Chao-Yuan Wu, Alan Yuille, and Christoph Feichtenhofer.
  Masked feature prediction for self-supervised visual pre-training.
  _arXiv preprint arXiv:2112.09133_, 2021.
- Wen et al. (2022)
  Xin Wen, Bingchen Zhao, Anlin Zheng, Xiangyu Zhang, and Xiaojuan Qi.
  Self-supervised visual representation learning with semantic grouping.
  In _NeurIPS_, 2022.
- Xie et al. (2021a)
  Jiahao Xie, Xiaohang Zhan, Ziwei Liu, Yew Soon Ong, and Chen Change Loy.
  Unsupervised object-level representation learning from scene images.
  In _NeurIPS_, 2021a.
- Xie et al. (2018)
  Saining Xie, Chen Sun, Jonathan Huang, Zhuowen Tu, and Kevin Murphy.
  Rethinking spatiotemporal feature learning: Speed-accuracy trade-offs in video classification.
  In _ECCV_, 2018.
- Xie et al. (2021b)
  Zhenda Xie, Zheng Zhang, Yue Cao, Yutong Lin, Jianmin Bao, Zhuliang Yao, Qi Dai, and Han Hu.
  Simmim: A simple framework for masked image modeling.
  _arXiv preprint arXiv:2111.09886_, 2021b.
- Xu et al. (2019)
  Dejing Xu, Jun Xiao, Zhou Zhao, Jian Shao, Di Xie, and Yueting Zhuang.
  Self-supervised spatiotemporal learning via video clip order prediction.
  In _CVPR_, 2019.
- Xu et al. (2018)
  Ning Xu, Linjie Yang, Yuchen Fan, Jianchao Yang, Dingcheng Yue, Yuchen Liang, Brian Price, Scott Cohen, and Thomas Huang.
  Youtube-vos: Sequence-to-sequence video object segmentation.
  In _Proceedings of the European conference on computer vision (ECCV)_, pages 585–601, 2018.
- Yang et al. (2024)
  Lihe Yang, Binghui Kang, Zhiwen Huang, Xiaoxiao Xu, Jonathan Feng, and Hengshuang Zhao.
  Depth anything: Unleashing the power of large-scale unlabeled data.
  In _CVPR_, 2024.
- Yun et al. (2022)
  Sukmin Yun, Hankook Lee, Jaehyung Kim, and Jinwoo Shin.
  Patch-level representation learning for self-supervised vision transformers.
  In _CVPR_, 2022.
- Zellers et al. (2022)
  Rowan Zellers, Jiasen Lu, Ximing Lu, Youngjae Yu, Yanpeng Zhao, Mohammadreza Salehi, Aditya Kusupati, Jack Hessel, Ali Farhadi, and Yejin Choi.
  Merlot reserve: Neural script knowledge through vision and language and sound.
  In _Proceedings of the IEEE/CVF conference on computer vision and pattern recognition_, pages 16375–16387, 2022.
- Zhang et al. (2023)
  Hang Zhang, Xin Li, and Lidong Bing.
  Video-llama: An instruction-tuned audio-visual language model for video understanding.
  _arXiv preprint arXiv:2306.02858_, 2023.
- Zhang et al. (2016)
  Richard Zhang, Phillip Isola, and Alexei A. Efros.
  Colorful image colorization.
  In _ECCV_, 2016.
- Zhang et al. (2024)
  Yuanhan Zhang, Jinming Wu, Wei Li, Bo Li, Zejun Ma, Ziwei Liu, and Chunyuan Li.
  Video instruction tuning with synthetic data.
  _arXiv preprint arXiv:2410.02713_, 2024.
- Zhao et al. (2024)
  Long Zhao, Nitesh B Gundavarapu, Liangzhe Yuan, Hao Zhou, Shen Yan, Jennifer J Sun, Luke Friedman, Rui Qian, Tobias Weyand, Yue Zhao, et al.
  Videoprism: A foundational visual encoder for video understanding.
  _arXiv preprint arXiv:2402.13217_, 2024.
- Zhou et al. (2017a)
  Bolei Zhou, Hang Zhao andXavier Puig, Sanja Fidler, Adela Barriuso, and Antonio Torralba.
  Scene parsing through ade20k dataset.
  In _CVPR_, 2017a.
- Zhou et al. (2017b)
  Bolei Zhou, Hang Zhao, Xavier Puig, Sanja Fidler, Adela Barriuso, and Antonio Torralba.
  Scene parsing through ade20k dataset.
  In _Proceedings of the IEEE conference on computer vision and pattern recognition_, pages 633–641, 2017b.
- Zhou et al. (2021)
  Jinghao Zhou, Chen Wei, Huiyu Wang, Wei Shen, Cihang Xie, Alan Yuille, and Tao Kong.
  ibot: Image bert pre-training with online tokenizer.
  _arXiv preprint arXiv:2111.07832_, 2021.
- Ziegler and Asano (2022)
  Adrian Ziegler and Yuki M. Asano.
  Self-supervised learning of object parts for semantic segmentation.
  In _CVPR_, 2022.

<a id="section-6"></a>

## 6 Pretraining details

<a id="table-11"></a>

> Table 11: Pretraining hyperparameters for the Primary and Cooldown phases. Hyperparameters are identical across all our ViT architectures (ViT-L, -g and -G).

| Parameter                           | Primary Phase                | Cooldown Phase                 |
| ----------------------------------- | ---------------------------- | ------------------------------ |
| Parameter                           | Primary Phase                | Cooldown Phase                 |
| Parameter                           | Primary Phase                | Cooldown Phase                 |
| Number of frames                    | 16                           | 64                             |
| Number of frames                    | 16                           | 64                             |
| Number of frames                    | 16                           | 64                             |
| Frames per Second                   | 4.0                          | 4.0                            |
| Frames per Second                   | 4.0                          | 4.0                            |
| Frames per Second                   | 4.0                          | 4.0                            |
| Video Crop Size                     | 256                          | 384                            |
| Video Crop Size                     | 256                          | 384                            |
| Video Crop Size                     | 256                          | 384                            |
| Image Crop Size                     | 256                          | 512                            |
| Image Crop Size                     | 256                          | 512                            |
| Image Crop Size                     | 256                          | 512                            |
| Random Resize Aspect Ratio          | [0.75, 1.35]                 | [0.75, 1.35]                   |
| Random Resize Aspect Ratio          | [0.75, 1.35]                 | [0.75, 1.35]                   |
| Random Resize Aspect Ratio          | [0.75, 1.35]                 | [0.75, 1.35]                   |
| Random Resize Scale                 | [0.3, 1.0]                   | [0.3, 1.0]                     |
| Random Resize Scale                 | [0.3, 1.0]                   | [0.3, 1.0]                     |
| Random Resize Scale                 | [0.3, 1.0]                   | [0.3, 1.0]                     |
| Steps                               | 135,000                      | 12000                          |
| Steps                               | 135,000                      | 12000                          |
| Steps                               | 135,000                      | 12000                          |
| Warmup Steps                        | 12,000                       | N/A                            |
| Warmup Steps                        | 12,000                       | N/A                            |
| Warmup Steps                        | 12,000                       | N/A                            |
| Image batch Size (global)           | 2,304                        | 2,304                          |
| Image batch Size (global)           | 2,304                        | 2,304                          |
| Image batch Size (global)           | 2,304                        | 2,304                          |
| Video batch Size (global)           | 128                          | 128                            |
| Video batch Size (global)           | 128                          | 128                            |
| Video batch Size (global)           | 128                          | 128                            |
| Starting Learning Rate              | 1e-4                         | 6e-4                           |
| Starting Learning Rate              | 1e-4                         | 6e-4                           |
| Starting Learning Rate              | 1e-4                         | 6e-4                           |
| Final Learning Rate                 | 5.25e-4                      | 1e-6                           |
| Final Learning Rate                 | 5.25e-4                      | 1e-6                           |
| Final Learning Rate                 | 5.25e-4                      | 1e-6                           |
| Weight Decay                        | 0.04                         | 0.04                           |
| Weight Decay                        | 0.04                         | 0.04                           |
| Weight Decay                        | 0.04                         | 0.04                           |
| EMA                                 | 0.99925                      | 0.99925                        |
| EMA                                 | 0.99925                      | 0.99925                        |
| EMA                                 | 0.99925                      | 0.99925                        |
| Spatial Mask Scale                  | [0.15, 0.7]                  | [0.15, 0.7]                    |
| Spatial Mask Scale                  | [0.15, 0.7]                  | [0.15, 0.7]                    |
| Spatial Mask Scale                  | [0.15, 0.7]                  | [0.15, 0.7]                    |
| Temporal Mask Scale                 | [1.0, 1.0]                   | [1.0, 1.0]                     |
| Temporal Mask Scale                 | [1.0, 1.0]                   | [1.0, 1.0]                     |
| Temporal Mask Scale                 | [1.0, 1.0]                   | [1.0, 1.0]                     |
| Mask Aspect Ratio                   | [0.75, 1.5]                  | [0.75, 1.5]                    |
| Mask Aspect Ratio                   | [0.75, 1.5]                  | [0.75, 1.5]                    |
| Mask Aspect Ratio                   | [0.75, 1.5]                  | [0.75, 1.5]                    |
| Tubelet Size                        | 2                            | 2                              |
| Tubelet Size                        | 2                            | 2                              |
| Tubelet Size                        | 2                            | 2                              |
| Patch Size                          | 16                           | 16                             |
| Patch Size                          | 16                           | 16                             |
| Patch Size                          | 16                           | 16                             |
| Predictor Blocks                    | 24                           | 24                             |
| Predictor Blocks                    | 24                           | 24                             |
| Predictor Blocks                    | 24                           | 24                             |
| Predictor Embedding Size            | 384                          | 384                            |
| Predictor Embedding Size            | 384                          | 384                            |
| Predictor Embedding Size            | 384                          | 384                            |
| Encoder Intermediate Blocks (ViT-G) | [12, 24, 36, 48]             | [12, 24, 36, 48]               |
| Encoder Intermediate Blocks (ViT-G) | [12, 24, 36, 48]             | [12, 24, 36, 48]               |
| Encoder Intermediate Blocks (ViT-G) | [12, 24, 36, 48]             | [12, 24, 36, 48]               |
| Context Loss $\lambda$              | 0.5 for video, 0.7 for image | 0.5 for videos, 0.7 for images |
| Context Loss $\lambda$              | 0.5 for video, 0.7 for image | 0.5 for videos, 0.7 for images |
| Context Loss $\lambda$              | 0.5 for video, 0.7 for image | 0.5 for videos, 0.7 for images |

In this section, we detail our pretraining protocol and provide hyper-parameters. We use identical hyper-parameters for all our ViT architectures (ViT-L, -g and -G). Following Assran et al. (2025), pretraining consists of two phases: 1) the primary phase, lasting for 135k iterations, where the learning rate follows a warmup (from 1e-4 to 5.25e-4) for 12k iterations, then a constant schedule (5.25e-4); and 2) a cooldown phase, lasting for 12k iterations, where the learning rate is decayed to a small value (from 6e-4 to 1e-6).

During the primary phase, video samples consist of 16-frames clips sampled at 4 frames per second, both video and images have a resolution of $256\times 256$. The cooldown phase is shorter, allowing for higher input resolution with manageable compute resources, video samples consist of 64-frames clips at resolution $384\times 384$ and images are sampled at resolution $512\times 512$. During both phases, the masking strategy follows the one introduced in Bardes et al. (2024), the image and video batch sizes are set to, respectively, 2304 and 128, the weight-decay is set to 0.04 and the EMA coefficient is set to 0.99925.

We use the standard ViT architecture with a patch size of 16 for both images and videos, and a tubelet size of 2 for videos. Our predictor has 24 blocks (versus 12 in V-JEPA 2) and an embedding size of 384. For our deep self-supervision loss, we use 4 intermediate blocks of the encoder, at equally spaced indices. The parameter $\lambda$ we use for Eq. [3](#S2.E3) is different for video and images, with a value of 0.5 for video and 0.7 for images.

<a id="section-7"></a>

## 7 Distillation details

Our distillation protocol is adapted from the pretraining recipe, maintaining the same JEPA loss, masking, architecture, and hyperparameters, except for a few key modifications: the Exponential Moving Average (EMA) encoder is replaced by a frozen Teacher network. The predictor’s final layer embedding dimension is adapted to match the Teacher’s dimension to enable the computation of the loss. We do not use deep-self-supervision for distillation: the predictor operates only on the last layer of the encoder, and the loss is only calculated on this last layer. We do not initialize the predictor with the pretraining weights and instead retrain a new predictor, which has 12 blocks (instead of 24 for pretraining), greatly improving distillation stability. Throughout training, a separate EMA of the context encoder is maintained, corresponding to Polyak averaging, which is never used in the loss calculation but serves as the final, high-performing model released for downstream tasks.

Distillation follows a multi-stage training approach similar to pretraining. Stage 1 (Primary Phase) with a warmup-then-constant schedule and low-resolution data (16 frames, $256\times 256$ pixels) using a pre-cooldown low-resolution V-JEPA 2.1 ViT-G as the teacher, and Stage 2 (Cooldown Phase) with a short annealing schedule and high-resolution data (64 frames, $384\times 384$) using the corresponding post-cooldown high-resolution V-JEPA 2.1 ViT-G as the teacher. The Stage 2 student network is initialized with the EMA student network from Stage 1, a two-stage strategy found to produce the best-performing models compared to alternatives such as single-stage approaches or always distilling from the final high-resolution V-JEPA 2.1 teacher.

<a id="section-8"></a>

## 8 Evaluation protocols

<a id="section-8-1"></a>

### 8.1 Depth Estimation

##### Datasets and Metrics.

We evaluated the geometric quality of the dense features of V-JEPA 2.1 in depth estimation on NYUv2 (Silberman et al., 2012b) and KITTI (Geiger et al., 2013a), reporting the root mean square error (RMSE).

##### Evaluation Protocol.

For fair comparison with the state-of-the-art, we adopted the same protocol reported by Siméoni et al. (2025), training a corresponding linear classifier on the training set of each data set.
The linear layer is applied only on top of the V-JEPA 2.1 visual encoder frozen patch features, and it is further normalized using a learned BatchNorm layer.
Note that we both train and evaluate single-image classifiers, as we process individual images using the 2D Convolution image tokenizer described in Sec.[2.3.4](#S2.SS3.SSS4).
We sweep learning rates $\{1.5\!\times\!10^{-3},1\!\times\!10^{-3},8\!\times\!10^{-4},3\!\times\!10^{-4},1\!\times\!10^{-4},8\!\times\!10^{-5},3\!\times\!10^{-5}\}$ and weight decay $\{10^{-3},10^{-4}\}$.

<a id="section-8-2"></a>

### 8.2 Semantic Segmentation

##### Datasets and Metrics.

We evaluate semantic segmentation with linear probing on the image semantic segmentation datasets ADE20K (Zhou et al., 2017a), Pascal VOC12 (Everingham et al., 2015), and Cityscapes (Cordts et al., 2016), reporting mean intersection-over-union (mIoU).

##### Evaluation Protocol.

Similarly, we also follow the same protocol reported in DINOv3 Siméoni et al. (2025).
We train a linear classifier on top of last-block patch features from the frozen encoder (already normalized via LayerNorm).
Similar to the depth estimation evaluation protocol, we both train and evaluate single-image classifiers.
Linear probes are optimized with AdamW using learning rates
$\{1.5\!\times\!10^{-3},8\!\times\!10^{-4},5\!\times\!10^{-4},8\!\times\!10^{-5}\}$ and weight decay $\{0.1,0.01,10^{-4}\}$.
We use a $512$px resolution for ADE20K and VOC12, and $1024$px height for Cityscapes.

<a id="section-8-3"></a>

### 8.3 Video Object Segmentation Tracking

##### Dataset and Metrics.

We evaluate on DAVIS 2017 (Pont-Tuset et al., 2017) and YouTube-VOS (Xu et al., 2018). DAVIS provides dense annotations for train/val (60/30 videos). In YouTube-VOS, as only the training set is publicly available, we divided this set both training (80$\%$) and validation (20$\%$) videos.

##### Evaluation Protocol.

Following (Rajasegaran et al., 2025) and Siméoni et al. (2025), we implement a non-parametric label-propagation approach based on cosine similarity between patch features from a frozen backbone.
Segmentation labels from the first frame are encoded as one-hot patch assignments. For each subsequent frame, we compute similarities with patches from the first frame and a small set of past frames, and propagate labels via a weighted $k$-NN scheme within a spatial neighborhood.

We sweep over several hyperparameters, including context length $\{4,7,10,15\}$, neighborhood size $\{12,24,36\}$, neighborhood shape $\{\text{square},\text{circle}\}$, top-$k$ neighbors $\{3,5,10\}$, and similarity temperature $\{0.01,0.1,0.2,0.7\}$.
Hyperparameters are selected on the DAVIS training set and applied to all test splits. We use an input resolution of 480px.

<a id="section-8-4"></a>

### 8.4 Short Term Object Interaction Anticipation

##### Dataset and Metrics.

We evaluate V-JEPA 2.1 on the STA v2 split of Ego4D (Grauman et al., 2022), which comprises 243 hours of annotated video clips spanning 128 noun and 81 verb categories, with a total of 98,276 training and 47,395 validation samples.
Following the established evaluation protocol (Grauman et al., 2022), we report Top-5 Average Precision (AP) and Top-5 mean Average Precision (mAP) metrics. As in standard mAP, predictions are matched to ground-truth boxes using IoU > 0.5 and additional class-specific criteria. For instance, the Top-5 mAP All variant requires a correct noun, correct verb, IoU above 0.5, and a time-to-contact $\delta$ prediction within a 0.25-second tolerance. To address the inherently multi-modal nature of future anticipation—where multiple plausible next-active objects may exist—the metric discounts up to four highest-scoring false positives per example, thereby avoiding penalties for plausible but unannotated predictions.
Additionally, we report individual metrics to evaluate the temporal ($\delta$), spatial (bounding boxes), and semantic (noun and verb) dimensions of the task.

##### Evaluation Protocol.

For a fair comparison with the previous state-of-the-art, we follow the official StillFast baseline implementation (Ragusa et al., 2023), which extends Faster R-CNN (Girshick, 2015).
Our attentive probe consists of four attention blocks followed by the frame-guided temporal pooling mechanism of (Mur-Labadia et al., 2024), since STA predictions must remain spatially aligned with the last video frame.
This pooling mechanism adopts a residual cross-attention module between the 3D tokens of the full video clip and the 2D tokens of the last frame. Queries are computed from the last-frame tokens via a linear projection, while keys and values are obtained from the video tokens using corresponding projections.
Once the video tokens are pooled in 2D, we apply a bilinear interpolation to match the resolution of the high-resolution image tokens. Both representations are summed and fused through a 2D convolution layer. Finally, we upsample this representation to produce a multi-scale pyramid at $1/4$, $1/8$, $1/16$, $1/32$, and $1/64$ of the image input resolution. This pyramid forms the input to the prediction head, which follows the design used in prior work (Ragusa et al., 2023; Mur-Labadia et al., 2024; Thakur et al., 2023).

##### Probe Architecture.

In this prediction head, first a Region Proposal Network (RPN) generates proposals from a feature pyramid, and RoIAlign extracts corresponding local features.
To enrich these features with scene-level context, we concatenate to each local RoI feature the resulting pooled token from the 4-layers attentive probe.
The fused representation is processed by two fully connected layers and added back to the local features through a residual connection, enabling global cues to modulate––rather than replace––local information.
Noun, verb and time to contact $\delta$ are predicted using respective linear layers from the fused RoI features. A Softplus activation layers is applied to the $\delta$ output in order to obtain positive predictions.
Training is end-to-end, combining standard Faster R-CNN losses with an additional verb loss $\mathcal{L}_{v}$ and a Smooth-$L_{1}$ TTC loss $\mathcal{L}_{\text{ttc}}$, weighted by 0.1 and 0.5 respectively.

##### Optimization.

Models are optimized with Adam using learning rates in $\{1\!\times\!10^{-5},\,8\!\times\!10^{-5},\,1.2\!\times\!10^{-4},\,2\!\times\!10^{-4},\,5\!\times\!10^{-4}\}$. We additionally explore different input configurations, including sampling rates $\{16,8,4,2\}\,\text{fps}$, clip lengths $\{32,16,8,4\}$ frames, and spatial resolutions $\{256\text{px},\,384\text{px}\}$, covering videos with varying temporal spans. We follow the multi-scale training strategy of Faster R-CNN, sampling image short sides uniformly from $\{640,672,704,736,768,800\}$ with a maximum long side of 1333 px. Our final best configuration consist of 16 frames videos at 384px with a sampling rate of 2 fps, and using a learning rate of $1.2\!\times\!10^{-4}$. We apply the same protocol to DINOv2 Oquab et al. (2023), DINOv3 Siméoni et al. (2025) and V-JEPA 2 Assran et al. (2025) models, reporting the best respective performance.

<a id="section-8-5"></a>

### 8.5 Video and Image Classification

##### Dataset and Metrics.

We use the evaluation benchmarks of V-JEPA 2 and evaluate our models on image classification on ImageNet Deng et al. (2009), and video classification on Kinetics-400 Kay et al. (2017), Something-Something-v2 Goyal et al. (2017) and Diving-48 Li et al. (2018).

##### Probe Architecture.

We train an attentive probe on top of the frozen encoder output using the training data from each downstream task. Our attentive probe is composed of four transformer blocks, each using 16 heads in the attention layer. The first three blocks use standard self-attention; the final block uses a cross-attention layer with a learnable query token. The output of the cross-attention layer in the final block is added back to the query token as a residual connection before applying the rest of the block (LayerNorm, followed by MLP with a single GeLU activation). The transformer blocks are followed by a final linear classifier layer.

##### Evaluation Protocol.

We follow the evaluation protocol of V-JEPA 2. For video evaluations, we sampled multiple clip segments from each input video. During validation, we also extracted three spatial views from each segment (instead of one view during training). The number of clip segments, frame step parameter, and global batch size vary for each evaluation. We use $64\times 2\times 3$ input for SSv2 (16 frames clip, 2 temporal crops, 3 spatial crops), $16\times 8\times 3$ for K400, and $32\times 4\times 3$ for Diving-48. For all benchmarks, we use a spatial resolution of $384\times 384$. We use the 2D or 3D tokenizer, respectively, for image and video benchmarks. We use a batch size of 256 except for ImageNet, we use 1024. For ImageNet, we do not use multiple clips or views per sample. For Diving-48, we employ a multilayer strategy. Instead of attending to the tokens from only the last layer of the encoder, we extract tokens from four encoder layers (the last layer and three intermediate layers) and attend to all of them.

##### Optimization.

For each evaluation, we simultaneously train multiple classifier heads with different hyper-parameters (learning rate and weight decay), reporting the accuracy of the best-performing classifier. For most of our evaluations (Kinetics, SSv2, and ImageNet), we train for 20 epochs and use 20 heads, each
using one of five learning rate values and four weight decay values, and the learning rate decays according to a cosine schedule. For Diving-48, which benefit from longer training, we train for 50 epochs.

<a id="section-8-6"></a>

### 8.6 Action Anticipation

##### Dataset and Metrics.

We evaluated V-JEPA 2.1 on the Action Anticipation task of the Epic-Kitchen-100 benchmark Damen et al. (2022). The EK100 dataset is comprised of 100 hours of cooking activities recorded from an egocentric perspective across 45 kitchen environments. Each video in EK100 is annotated with action segments, which include a start timestamp, an end timestamp, and an action label. There are 3,568 unique action labels, each consisting of a verb and a noun category, with a total of 97 verb categories and 300 noun categories. The EK100 action anticipation task involves predicting noun, verb, and action (i.e., predicting verb and noun jointly) from a video clip, referred to as context, that occurs before the start timestamp of an action segment.
The interval between the end of the context and the beginning of the action segment is the anticipation time, which is set to 1 second by default. Given that different future actions may be possible from a given context, mean-class recall-at-5 for noun, verb and action, is used as the metric to measure performance (Damen et al., 2022).

##### Evaluation Protocol.

We follow the same evaluation protocol introduced in V-JEPA 2 and use a focal loss Lin et al. (2017b) with $\alpha$ = 0.25 and $\gamma$ = 2.0 when training the probe. We used a context of 32 frames with a frame-rate of 8 frames per second at resolution $384\times 384$. During probe training, we randomly sample an anticipation time between 0.25 and 1.75 seconds and an anticipation point between 0.0 and 0.25. Our probe architecture for action anticipation follows the architecture introduced in V-JEPA 2 and described in Appendix [8.5](#S8.SS5), consisting of four transformer blocks, including a last cross-attention layer with a set of learnable query tokens, followed by a final linear classifier layer for each query token.

<a id="section-9"></a>

## 9 Additional Ablations

<a id="section-9-1"></a>

### 9.1 Multi-scale evaluation

We evaluate the impact of Deep Self-Supervision on the need for multi-scale evaluation, i.e. using multiple layers of the encoder as input to the evaluation probe. Table [12](#S9.T12) compares a model trained with Deep Self-Supervision with a model trained without, and we measure performance on image segmentation on ADE20k, depth estimation on NYU, and action recognition on Diving-48, using either; a) only the last layer of the encoder as input to the probe (Last-Layer) or b) 4 equally spaced intermediate layers (4-Layers). We observe that the model trained without Deep Self-Supervision has a wide gap in performance between using Last-Layer and 4-Layers, and benefits a lot from multi-scale evaluation. On the other hand, the model trained with Deep Self-Supervision is already stronger using Last-Layer, and only benefits a little from using 4-Layers.

<a id="table-12"></a>

> Table 12: Impact of deep self-supervision on the need for multi-scale evaluation. We conduct experiments with our V-JEPA 2.1 ViT-L trained from scratch. Last-Layer indicates that evaluation is conducted with only the last layer of the encoder as input to the probe. 4-Layers indicates that evaluation is conducted by concatenating 4 intermediate layers of the encoder and feeding it to the probe.

| Deep Self-Supervision | ADE20k     | NYU      | Diving-48  |          |            |          |
| --------------------- | ---------- | -------- | ---------- | -------- | ---------- | -------- |
| Deep Self-Supervision | ADE20k     | NYU      | Diving-48  |          |            |          |
| Deep Self-Supervision | ADE20k     | NYU      | Diving-48  |          |            |          |
| Deep Self-Supervision | ADE20k     | NYU      | Diving-48  |          |            |          |
|                       | Last-Layer | 4-Layers | Last-Layer | 4-Layers | Last-Layer | 4-Layers |
|                       | Last-Layer | 4-Layers | Last-Layer | 4-Layers | Last-Layer | 4-Layers |
|                       | Last-Layer | 4-Layers | Last-Layer | 4-Layers | Last-Layer | 4-Layers |
|                       | Last-Layer | 4-Layers | Last-Layer | 4-Layers | Last-Layer | 4-Layers |
|                       | Last-Layer | 4-Layers | Last-Layer | 4-Layers | Last-Layer | 4-Layers |
|                       | Last-Layer | 4-Layers | Last-Layer | 4-Layers | Last-Layer | 4-Layers |
|                       | Last-Layer | 4-Layers | Last-Layer | 4-Layers | Last-Layer | 4-Layers |
| ✗                     | 34.9       | 39.1     | 0.513      | 0.463    | 85.8       | 86.9     |
| ✗                     | 34.9       | 39.1     | 0.513      | 0.463    | 85.8       | 86.9     |
| ✗                     | 34.9       | 39.1     | 0.513      | 0.463    | 85.8       | 86.9     |
| ✗                     | 34.9       | 39.1     | 0.513      | 0.463    | 85.8       | 86.9     |
| ✗                     | 34.9       | 39.1     | 0.513      | 0.463    | 85.8       | 86.9     |
| ✗                     | 34.9       | 39.1     | 0.513      | 0.463    | 85.8       | 86.9     |
| ✗                     | 34.9       | 39.1     | 0.513      | 0.463    | 85.8       | 86.9     |
| ✔                     | 42         | 43.9     | 0.381      | 0.370    | 87.2       | 88.1     |
| ✔                     | 42         | 43.9     | 0.381      | 0.370    | 87.2       | 88.1     |
| ✔                     | 42         | 43.9     | 0.381      | 0.370    | 87.2       | 88.1     |
| ✔                     | 42         | 43.9     | 0.381      | 0.370    | 87.2       | 88.1     |
| ✔                     | 42         | 43.9     | 0.381      | 0.370    | 87.2       | 88.1     |
| ✔                     | 42         | 43.9     | 0.381      | 0.370    | 87.2       | 88.1     |
| ✔                     | 42         | 43.9     | 0.381      | 0.370    | 87.2       | 88.1     |

<a id="section-9-2"></a>

### 9.2 Pretraining Spatial Resolution

Table [13](#S9.T13) presents the impact of the resolution used during the cooldown phase of pretraining on performance on most of our downstream tasks. We compare models trained with a video spatial resolution of $256\times 256$ to the models we present in the main paper that are trained with a video spatial resolution of $384\times 384$. V-JEPA 2.1 benefits from higher resolution pretraining across all of our downstream tasks.

<a id="table-13"></a>

> Table 13: Impact of pretraining spatial resolution. We compare models trained during the cooldown phase at $256\times 256$ spatial resolution against $384\times 384$.

| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| ----- | --- | ---- | ---- | ---- | ---- | ----- | ------ | ------ | ---- | ----- | ----- | ----- | ------ |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| Model | Res | SSv2 | D-48 | K400 | IN1K | EK100 | ADE20k | Citys. | VOC  | NYU   | KITTI | DAVIS | YT-VOS |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 256 | 76.7 | 88.6 | 86.2 | 84.1 | 35.7  | 47.8   | 71.7   | 84.6 | 0.359 | 2.611 | 68.0  | 72.0   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-g | 384 | 76.9 | 89   | 87   | 84.8 | 38.4  | 47.8   | 71.8   | 84.7 | 0.350 | 2.601 | 67.4  | 71.3   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 256 | 77.1 | 89.5 | 87.3 | 84.8 | 38.8  | 47.8   | 73.2   | 84.7 | 0.313 | 2.472 | 68.6  | 72.7   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
| ViT-G | 384 | 77.7 | 89.2 | 87.7 | 85.5 | 40.8  | 47.9   | 73.5   | 85.0 | 0.307 | 2.461 | 69.0  | 72.6   |
