# Fine-Tuning Vision-Language-Action Models: Optimizing Speed and Success

Moo Jin Kim ${}^{1}$ Chelsea Finn ${}^{1}$ Percy Liang ${}^{1}$

https://openvla-oft.github.io

Abstract-Recent vision-language-action models (VLAs) build upon pretrained vision-language models and leverage diverse robot datasets to demonstrate strong task execution, language following ability, and semantic generalization. Despite these successes, VLAs struggle with novel robot setups and require fine-tuning to achieve good performance, yet how to most effectively fine-tune them is unclear given many possible strategies. In this work, we study key VLA adaptation design choices such as different action decoding schemes, action representations, and learning objectives for fine-tuning, using OpenVLA as our representative base model. Our empirical analysis informs an Optimized Fine-Tuning (OFT) recipe that integrates parallel decoding, action chunking, a continuous action representation, and a simple L1 regression-based learning objective to altogether improve inference efficiency, policy performance, and flexibility in the model's input-output specifications. We propose OpenVLA-OFT, an instantiation of this recipe, which sets a new state of the art on the LIBERO simulation benchmark, significantly boosting OpenVLA's average success rate across four task suites from 76.5% to 97.1% while increasing action generation throughput by ${26} \times$ . In real-world evaluations, our fine-tuning recipe enables OpenVLA to successfully execute dexterous, high-frequency control tasks on a bimanual ALOHA robot and outperform other VLAs $\left( {\pi }_{0}\right.$ and RDT-1B) fine-tuned using their default recipes, as well as strong imitation learning policies trained from scratch (Diffusion Policy and ACT) by up to ${15}\%$ (absolute) in average success rate. We release code for OFT and pretrained model checkpoints at https://openvla-off.github.io.

## I. INTRODUCTION

Recent vision-language-action models (VLAs)-robot policies built by fine-tuning pretrained vision-language models on large-scale robot datasets for low-level robotic control-have demonstrated strong task performance, semantic generalization, and language following abilities across diverse robots and tasks $\left\lbrack  {4,{34},{24},{23},7,{15},8,{53},{58},3}\right\rbrack$ . Despite their strengths, fine-tuning is crucial for satisfactory deployment of VLAs on novel robots and tasks, yet it is unclear what the most effective approach for adaptation is given the large design space. A robotics practitioner who wishes to fine-tune a VLA to a new robot setup and task may default to using the same training recipe used for pretraining (or a parameter-efficient variant), but it is not obvious whether this would yield the best policy, and there is limited empirical analysis of alternative fine-tuning approaches in the literature.

Prior work has begun exploring VLA adaptation strategies, with Kim et al. [23] proposing parameter-efficient fine-tuning via LoRA. However, their autoregressive action generation remains too slow (3-5 Hz) for high-frequency control (25- 50+ Hz), and both LoRA and full fine-tuning of autoregressive VLAs often yield unsatisfactory performance in bimanual manipulation tasks [54, 27, 3]. While recent approaches improve efficiency through better action tokenization schemes [2, 38], achieving 2 to ${13} \times$ speedups, significant latency between action chunks (e.g., ${750}\mathrm{\;{ms}}$ for the recent FAST approach [38]) still limits real-time deployment on high-frequency bimanual robots. Exploring alternative VLA adaptation approaches that achieve both satisfactory speed and quality remains an under-explored area of research.

In this work, we study key design decisions for adapting VLAs to novel robots and tasks using OpenVLA, a representative autoregressive VLA, as our base model. We examine three key design choices: action decoding scheme (autoregressive vs. parallel generation), action representation (discrete vs. continuous), and learning objective (next-token prediction vs. L1 regression vs. diffusion). Our study reveals several key insights that build on each other: (1) parallel decoding with action chunking not only boosts inference efficiency but also improves success rates on downstream tasks while enabling greater flexibility in the model's input-output specifications; (2) continuous action representations further improve model quality compared to discrete representations; and (3) fine-tuning the VLA with an L1 regression objective yields comparable performance to diffusion-based fine-tuning while offering faster training convergence and inference speed.

Building on these insights, we introduce OpenVLA-OFT: an instantiation of an Optimized Fine-Tuning (OFT) recipe that integrates parallel decoding and action chunking, continuous action representations, and an L1 regression objective to enhance inference efficiency, task performance, and model input-output flexibility while maintaining algorithmic simplicity. We conduct experiments on both the standardized LIBERO simulation benchmark and dexterous tasks on a real bimanual ALOHA robot. In LIBERO, OpenVLA-OFT establishes a new state of the art by achieving 97.1% average success rate across four task suites, outperforming both fine-tuned OpenVLA policies [23] (76.5%) and ${\pi }_{0}$ policies [3] (94.2%) while achieving a ${26} \times$ speedup in action generation with 8-step action chunks. For real-world ALOHA tasks [56], we augment our recipe with FiLM [37] for enhanced language grounding, denoting the augmented recipe as OFT+. OpenVLA-OFT+ successfully executes dexterous bimanual tasks like folding clothes and manipulating target food items based on the user's prompt (see Figure 1), outperforming both fine-tuned VLAs ( ${\pi }_{0}$ and RDT-1B) and prominent imitation learning policies trained from scratch (Diffusion Policy and ACT) by up to 15% (absolute) in average success rate. With 25-timestep action chunks, OpenVLA-OFT+ achieves ${43} \times$ faster throughput than base OpenVLA, demonstrating that our new fine-tuning recipe enables real-time robot control with strong task performance and language following ability.

---

${}^{1}$ Stanford University. Correspondence to: Moo Jin Kim <moojink@cs.stanford.edu>, Chelsea Finn <cbfinn@cs.stanford.edu>, Percy Liang <pliang@cs.stanford.edu>.

---

![1_213_155_1373_795_0.jpg](images/1_213_155_1373_795_0.jpg)

Fig. 1: OpenVLA-OFT+ on the bimanual ALOHA robot. Our Optimized Fine-Tuning (OFT) recipe enhances fine-tuned OpenVLA policies through improved inference efficiency, model quality, and input-output flexibility. The resulting OpenVLA-OFT+ policies execute diverse dexterous manipulation tasks on a real-world bimanual robot at high control frequencies (25 Hz). The "+" suffix indicates the integration of feature-wise linear modulation (FiLM) [37], which strengthens language grounding in tasks where accurate language understanding is critical for success.

## II. RELATED WORK

Prior works have leveraged language and vision foundation models to enhance robotic capabilities, using them as pretrained visual representations that accelerate robotic policy learning [30, 33, 31, 20, 32], for object localization in robotics tasks [9, 47], and for high-level planning and reasoning [1, 17, 44, 16, 45, 18, 6]. More recently, researchers have explored fine-tuning vision-language models (VLMs) to directly predict low-level robotic control actions, producing "vision-language-action" models (VLAs) [4, 34, 24, 23, 7, 15, 8, 53, 58, 54, 3, 2], which have demonstrated effective language following [59] and generalization to out-of-distribution test conditions and unseen semantic concepts. These works focus primarily on model development, while we focus on developing a recipe for fine-tuning such models, justifying individual design decisions with insights that we gain from our empirical analysis.

Despite the importance of fine-tuning for real-world VLA deployment, empirical analysis of effective fine-tuning recipes remains limited. While Kim et al. [23] study various parameter update strategies and from their findings show that LoRA fine-tuning enables effective adaptation to single-arm robots operating at low control frequencies $\left( { < {10}\mathrm{\;{Hz}}}\right)$ , their analysis does not extend to bimanual robots with high control frequencies (25-50+ Hz), a more complex control scenario. We address this gap by exploring VLA adaptation design decisions for fast inference and reliable task execution on a real-world bimanual manipulator with a ${25}\mathrm{\;{Hz}}$ controller.

Recent works by Belkhale and Sadigh [2] and Pertsch et al. [38] improve VLA efficiency through new action to-kenization schemes, using vector quantization or discrete cosine transform-based compression to represent action chunks (sequences of actions) with fewer tokens than simple per-dimension binning (as used in RT-2 [4] and OpenVLA [23]). While these approaches achieve 2 to ${13} \times$ speedups for autoregressive VLAs, we explore design decisions beyond autoregressive modeling, which remains inherently limited by iterative generation. Our parallel decoding approach, when paired with action chunking, achieves significantly greater speedups: ${26} \times$ to ${43} \times$ throughput with much lower latency (0.07 ms for single-arm tasks with one input image and 0.321 ms for bimanual tasks with three input images).

Another line of research [54, 27, 3] demonstrates effective VLA fine-tuning for high-frequency, bimanual manipulation using generative approaches like diffusion or flow matching. While these diffusion-based VLAs achieve higher action throughput than autoregressive VLAs by generating multi-timestep action chunks simultaneously, they introduce computational trade-offs through slower training and multiple denois-ing or integration steps at inference time. Furthermore, these diffusion VLAs vary considerably in architecture, learning algorithm, vision-language fusion approach, and input-output specifications-and which design elements most significantly impact performance remains unclear. Through controlled experiments, we show that policies fine-tuned with a simpler L1 regression objective can match more complex approaches in task performance while achieving significantly greater inference efficiency.

![2_137_151_1519_247_0.jpg](images/2_137_151_1519_247_0.jpg)

Fig. 2: Key design decisions for VLA fine-tuning. Left: Comparison between autoregressive decoding, which generates actions sequentially, and parallel decoding, which leverages bidirectional attention and generates all actions in a single forward pass. Right: Comparison between discrete action tokens with next-token prediction and continuous action values with L1 regression or diffusion modeling objectives. The original OpenVLA training scheme includes autoregressive decoding, discrete actions, and next-token prediction.

Lastly, unlike prior work that relies on a separate faster low-level control policy in addition to a slower VLA [36], in this work we fine-tune the base VLA end-to-end with techniques that enable high efficiency without needing a separate controller. Further, unlike other works that collect online interaction data to continually update specialist policies via reinforcement learning [19], here we focus on the simpler imitation learning paradigm in which we develop high-performing policies just by training once offline on a fixed dataset of expert task demonstrations.

## III. PRELIMINARIES

Original OpenVLA formulation. We use OpenVLA [23] as our representative base VLA, a 7B-parameter manipulation policy created by fine-tuning the Prismatic VLM [21] on 1M episodes from the Open X-Embodiment dataset [34]. See Appendix A for architecture details. OpenVLA's original training formulation uses autoregressive prediction of 7 discrete robot action tokens per timestep: 3 for position control, 3 for orientation control, and 1 for gripper control. It employs next-token prediction with cross-entropy loss as its learning objective, similar to language models. We explore alternative formulations including parallel decoding, continuous action representations, and learning objectives like L1 regression and diffusion modeling in the next few sections.

Action chunking. Prior works have shown that action chunking-i.e., predicting and executing a sequence of future actions without intermediate replanning-improves policy success rates across many manipulation tasks [56, 5, 28]. However, OpenVLA's autoregressive generation scheme makes action chunking impractical, as generating even a single-timestep action takes 0.33 seconds on an NVIDIA A100 GPU. For a chunk size of $K$ timesteps and action dimensionality $D$ , OpenVLA requires ${KD}$ sequential decoder forward passes versus just $D$ passes without chunking. This $K$ -fold increase in latency makes action chunking impractical for high-frequency robots under the original formulation. In the next section, we present a parallel generation scheme that enables efficient action chunking.

## IV. STUDYING KEY VLA FINE-TUNING DESIGN DECISIONS

In this section, we first outline key design decisions for adapting VLAs to novel robot setups and tasks and provide details on their implementation.

### A.VLA Fine-Tuning Design Decisions

Existing approaches that fine-tune VLAs using the base model's autoregressive training recipe face two key limitations: slow inference speed (3-5 Hz) unsuitable for high-frequency control, and unreliable task execution on bimanual manipulators [54, 27, 3].

To address these challenges, we investigate three key design components for VLA fine-tuning:

(a) Action generation strategy (Figure 2, left): We compare autoregressive generation, which requires sequential token-by-token processing, with parallel decoding, which generates all actions simultaneously and enables efficient action chunking.

(b) Action representation (Figure 2, right): We examine discrete actions (256-bin discretization of normalized actions) processed through softmax-based token prediction, versus continuous actions directly generated by an MLP action head. For discrete actions, the final hidden states of the language model decoder are linearly projected into logits, which are processed by a softmax operation to form the probability distribution over action tokens. For continuous actions, the final hidden states are instead mapped directly to normalized continuous actions by a separate action head MLP.

(c) Learning objective (Figure 2, right): We compare policies fine-tuned with next-token prediction for discrete actions, L1 regression for continuous actions [56], and conditional denoising diffusion [5] for continous actions (similar to Chi et al. [5]).

We conduct our study using OpenVLA [23] as the base model, adapting it via LoRA fine-tuning [14] due to our relatively small training datasets (500 demonstrations versus 1M demonstrations for pretraining).

## B. Implementing Alternative Design Components

The base OpenVLA model originally employs autoregressive generation of discrete action tokens optimized via next-token prediction. We implement alternative design decisions for fine-tuning while keeping the original pretraining unchanged. We describe the key implementation aspects below, with further details explained in Appendix B.

Parallel decoding and action chunking. Unlike autoregressive generation which requires sequential token prediction, parallel decoding enables the model to map input embeddings to the predicted output sequence in a single forward pass. We modify the model to receive empty action embeddings as input and replace the causal attention mask with bidirectional attention, allowing the decoder to predict all actions simultaneously. This reduces action generation from $D$ sequential passes to a single pass, where $D$ is the action dimensionality.

Parallel decoding naturally extends to action chunking: to predict actions for multiple future timesteps, we simply insert additional empty action embeddings in the decoder's inputs, which are then mapped to a chunk of future actions. For chunk size $K$ , the model predicts ${KD}$ actions in one forward pass, increasing throughput $K$ -fold with minimal latency impact. While parallel decoding may theoretically be less expressive than autoregressive approaches, our experiments show no performance degradation across diverse tasks.

Continuous action representations. OpenVLA originally uses discrete action tokens where each action dimension is normalized to $\left\lbrack  {-1, + 1}\right\rbrack$ and uniformly discretized into 256 bins. While this approach is convenient since it requires no architectural modifications to the underlying VLM, the discretization process can sacrifice fine-grained action details. We study continuous action representations with two learning objectives drawn from prominent imitation learning approaches:

First, similar to Zhao et al. [56], we implement L1 regression by replacing the decoder's output embedding layer with an MLP action head that directly maps final decoder layer hidden states to continuous action values. The model is trained to minimize the mean L1 difference between predicted and ground-truth actions, maintaining the efficiency benefits of parallel decoding while potentially improving action precision.

Second, inspired by Chi et al. [5], we implement conditional denoising diffusion modeling where the model learns to predict noise added to action samples during forward diffusion. During inference, the policy gradually denoises noisy action samples via reverse diffusion to produce real actions. While this approach offers potentially more expressive action modeling, it requires multiple forward passes during inference (50 diffusion steps in our implementation), impacting deployment latency even with parallel decoding.

Additional model inputs and outputs. While the original OpenVLA processes a single camera view, some robot setups include multiple viewpoints and additional robot state information. We implement a flexible input processing pipeline: For camera images, we use OpenVLA's dual vision encoder to extract 256 patch embeddings per view, which are projected into the language embedding space with a shared projector network. For low-dimensional robot state inputs (e.g., joint angles and gripper state), we employ a separate projection network to map these into the same embedding space as one additional input embedding.

All input embeddings-visual features, robot state, and language tokens-are concatenated along the sequence dimension before being passed to the decoder. This unified latent representation enables the model to attend to all available information when generating actions. Combined with parallel decoding and action chunking, this architecture can efficiently process rich multimodal inputs while generating multiple timesteps of actions, as illustrated in Figure 1.

C. Augmenting OpenVLA-OFT with FiLM for Enhanced Language Grounding.

Challenges with language following. When deploying on the ALOHA robot setup with multiple viewpoints including from wrist-mounted cameras, we observe that policies can struggle with language following due to spurious correlations in visual inputs. During training, policies may learn to latch onto such spurious correlations when predicting actions, rather than properly attending to the language instructions, resulting in poor adherence to the user's commands at test time. Furthermore, language inputs may only be critical at specific moments in a task-for example, after grasping the spoon and deciding which ingredient to scoop in the "scoop X into bowl" task discussed in Section VI. Therefore, without special techniques, training the model to appropriately focus on language inputs can be particularly challenging.

FiLM. To enhance language following, we employ feature-wise linear modulation (FiLM) [37], which infuses language embeddings into the visual representations so that the model pays more attention to the language inputs. We compute the average of the language embeddings $\mathbf{x}$ from the task description and project it to obtain scaling and shifting vectors $\gamma$ and $\beta$ . These vectors modulate the visual features $\mathbf{F}$ through an affine transformation:

$$
\operatorname{FiLM}\left( {\mathbf{F} \mid  \gamma ,\beta }\right)  = \widehat{\mathbf{F}} = \left( {1 + \gamma }\right)  \odot  \mathbf{F} + \beta
$$

A crucial implementation detail is the choice of what represents a "feature" for modulation in vision transformers. While one might naturally consider treating individual patch embeddings as features to be modulated, we find that this approach results in poor language following. Instead, drawing from how FiLM operates in convolutional networks, where modulation applies spatially-agnostically by scaling and shifting entire feature maps, we apply each element of $\gamma$ and $\beta$ to the corresponding hidden unit across all visual patch embeddings so that $\gamma$ and $\beta$ influence all patch embeddings. Concretely, this makes $\gamma$ and $\beta {D}_{ViT}$ -dimensional vectors, where ${D}_{ViT}$ is the number of hidden dimensions (i.e., the number of elements in each of the patch embeddings in the vision transformer's latent representations).

![4_138_158_750_508_0.jpg](images/4_138_158_750_508_0.jpg)

Fig. 3: LIBERO simulation benchmark [26] task suites. We study VLA fine-tuning design decisions using four representative task suites. Here we depict two of ten tasks per suite.

We apply FiLM after the self-attention layer and before the feedforward layer in each vision transformer block, with separate projectors for each block (see Figure 8). Additional implementation details are provided in Appendix C. We only use FiLM for the ALOHA experiments discussed in Section VI, where multiple camera viewpoints lead to a larger presence of spurious correlations in visual inputs.

## V. EXPERIMENTS: EVALUATING VLA FINE-TUNING DESIGN DECISIONS

In this section, we evaluate the effects of our proposed VLA adaptation design decisions through controlled experiments aimed at answering three key questions:

1) How does each design decision affect the fine-tuned policy's success rate on downstream tasks?

2) How does each design decision affect model inference efficiency (action generation throughput and latency)?

3) How do the alternative fine-tuning formulations affect flexibility in model input-output specifications?

## A. LIBERO Experimental Setup

We evaluate on the LIBERO simulation benchmark [26], which features a Franka Emika Panda arm in simulation with demonstrations containing camera images, robot state, task annotations, and delta end-effector pose actions. We use four task suites—LIBERO-Spatial, LIBERO-Object, LIBERO-Goal, and LIBERO-Long—each providing 500 expert demonstrations across 10 tasks to assess policy generalization to different spatial layouts, objects, goals, and long-horizon tasks.

Following Kim et al. [23], we filter unsuccessful demonstrations and fine-tune OpenVLA via LoRA [14] on each task suite independently. We train for ${50} - {150}\mathrm{\;K}$ gradient steps for non-diffusion methods and ${100} - {250}\mathrm{\;K}$ steps for diffusion methods (which converge slower), using a batch size of 64-128 across 8 A100/H100 GPUs. We test checkpoints every 50K steps and report the best performance for each run. Unless specified otherwise, policies receive one third-person image and language instruction as input. For methods using action chunking, we set chunk size to $K = 8$ to match the Diffusion Policy baseline [5], and execute full chunks before replanning, which we find improves both speed and performance. See Appendix D for hyperparameter details.

Our primary baseline in this study is the base OpenVLA model fine-tuned using the original fine-tuning recipe. However, for broader comparison, we also include LIBERO results from prior state-of-the-art imitation learning methods, such as Diffusion Policy [5], Octo [49], DiT Policy [13], Seer [50], MDT [40], and ${\pi }_{0}$ [3]. Note that Seer uses additional LIBERO- 90 pretraining data.

## B. LIBERO Task Performance Comparisons

For satisfactory deployment, robot policies must demonstrate reliable task execution. We first assess how different VLA fine-tuning design decisions affect success rates on the LIBERO benchmark.

Our efficiency analysis (which we discuss later) reveals that parallel decoding (PD) and action chunking (AC) together are necessary for high-frequency control (25-50+ Hz), especially for bimanual robots with double the amount of action dimensions. We therefore evaluate OpenVLA policies with both techniques used jointly, comparing variants using discrete actions, continuous actions with L1 regression, and continuous actions with diffusion.

Results in Table I show that parallel decoding and action chunking not only increase throughput but also improve performance significantly, raising average success rates by 14% (absolute) over autoregressive OpenVLA policies. This improvement is particularly pronounced in LIBERO-Long, suggesting that action chunking helps capture temporal dependencies [28] and reduce compounding errors [41], which ultimately leads to smoother and more reliable task execution. In addition, we find that using continuous action variants further improves success rates by $5\%$ (absolute) over the discrete action variant, likely due to higher precision in the action predictions. L1 regression and diffusion variants achieve comparable performance, indicating that the high-capacity OpenVLA model can effectively model the multi-task action distribution even with simple L1 regression.

## C. LIBERO Inference Efficiency Comparisons

Efficient inference is crucial for deploying VLAs on high-frequency control robots. We now evaluate how parallel decoding (PD), action chunking (AC), and continuous action representations affect model inference speed. We measure average latency (time to generate one robot action or action chunk) and throughput (total actions generated per second) by querying each model variant 100 times on an NVIDIA A100 GPU. Each query processes a ${224} \times  {224}\mathrm{{px}}$ image and a sample LIBERO language instruction ("pick up the alphabet soup and place it in the basket").

TABLE I: LIBERO task performance results. Success rates (SR) across LIBERO benchmark task suites [26]. Results include policies fine-tuned from pretrained base models (Octo, DiT Policy, Seer, πo), models trained from scratch (Diffusion Policy, Seer (scratch), MDT), and OpenVLA variants using different fine-tuning design decisions: parallel decoding (PD), action chunking (AC, chunk size $K = 8$ timesteps), and continuous actions with L1 regression (Cont-L1) with diffusion (Cont-Diffusion). Unless otherwise specified, OpenVLA diffusion policies use 50 diffusion steps at both train and test time. OpenVLA results from this work are averaged over 500 trials for each task suite (10 tasks $\times  {50}$ episodes). Our full OpenVLA-OFT method with additional inputs achieves state-of-the-art 97.1% average success rate. Baseline results are from the original papers, except for Diffusion Policy, Octo, and the original OpenVLA policies, whose results are reported by Kim et al. [23]. Bold and underlined values indicate best and second-best performance. We separate the comparisons based on which inputs the policies receive as well as whether or not they were trained using modified datasets following Kim et al. [23] (in the modified versions, actions with near-zero magnitude and unsuccessful demonstrations are filtered out). *: MDT results with ${100}\%$ language annotations were obtained through direct correspondence with the authors.

Policy inputs: third-person image, language instruction

(Modified training dataset; unsuccessful demonstrations filtered out)

<table><tr><td></td><td>Spatial SR (%)</td><td>Object SR (%)</td><td>Goal SR (%)</td><td>Long SR (%)</td><td>Average SR (%)</td></tr><tr><td>Diffusion Policy (scratch) [5]</td><td>78.3</td><td>92.5</td><td>68.3</td><td>50.5</td><td>72.4</td></tr><tr><td>Octo (fine-tuned) [49]</td><td>78.9</td><td>85.7</td><td>84.6</td><td>51.1</td><td>75.1</td></tr><tr><td>DiT Policy (fine-tuned) [13]</td><td>84.2</td><td>96.3</td><td>85.4</td><td>63.8</td><td>82.4</td></tr><tr><td>OpenVLA (fine-tuned) [23]</td><td>84.7</td><td>88.4</td><td>79.2</td><td>53.7</td><td>76.5</td></tr><tr><td>OpenVLA (fine-tuned) + PD&AC</td><td>91.3</td><td>92.7</td><td>90.5</td><td>86.5</td><td>90.2</td></tr><tr><td>OpenVLA (fine-tuned) + PD&AC, Cont-Diffusion</td><td>96.9</td><td>98.1</td><td>95.5</td><td>91.1</td><td>95.4</td></tr><tr><td>OpenVLA-OFT (OpenVLA (fine-tuned) + PD&AC, Cont-L1) (ours)</td><td>96.2</td><td>98.3</td><td>96.2</td><td>90.7</td><td>95.3</td></tr></table>

Policy inputs: third-person image, wrist camera image, robot proprioceptive state (optional), language instruction

(Original unfiltered training dataset)

<table><tr><td></td><td>Spatial SR (%)</td><td>Object SR (%)</td><td>Goal SR (%)</td><td>Long SR (%)</td><td>Average SR (%)</td></tr><tr><td>MDT (scratch; with 2% language annotations) [40]</td><td>78.5</td><td>87.5</td><td>73.5</td><td>64.8</td><td>76.1</td></tr><tr><td>MDT (scratch; with 100% language annotations)*</td><td>95.2</td><td>97.8</td><td>-</td><td>83.0</td><td>-</td></tr><tr><td>Seer (scratch) [50]</td><td>-</td><td>-</td><td>-</td><td>78.7</td><td>-</td></tr><tr><td>Seer (pretrained on LIBERO-90, then fine-tuned) [50]</td><td>-</td><td>-</td><td>-</td><td>87.7</td><td>-</td></tr><tr><td>OpenVLA-OFT (OpenVLA (fine-tuned) + PD&AC, Cont-L1) (ours)</td><td>95.2</td><td>94.2</td><td>95.2</td><td>93.2</td><td>94.5</td></tr></table>

Policy inputs: third-person image, wrist camera image, robot proprioceptive state (optional), language instruction (Modified training dataset; unsuccessful demonstrations filtered out)

<table><tr><td></td><td>Spatial SR (%)</td><td>Object <br> SR (%)</td><td>Goal SR (%)</td><td>Long SR (%)</td><td>Average SR (%)</td></tr><tr><td>${\pi }_{0} +$ FAST (fine-tuned) [38]</td><td>96.4</td><td>96.8</td><td>88.6</td><td>60.2</td><td>85.5</td></tr><tr><td>${\pi }_{0}$ (fine-tuned) [3]</td><td>96.8</td><td>98.8</td><td>95.8</td><td>85.2</td><td>94.2</td></tr><tr><td>OpenVLA-OFT (OpenVLA (fine-tuned) + PD&AC, Cont-L1) (ours)</td><td>97.6</td><td>98.4</td><td>97.9</td><td>94.5</td><td>97.1</td></tr></table>

TABLE II: LIBERO inference efficiency results. Action generation throughput and latency for 7-dimensional actions, averaged over 100 queries on an NVIDIA A100 GPU. Each query processes a ${224} \times  {224}\mathrm{{px}}$ image and a LIBERO task command ("pick up the alphabet soup and place it in the basket"). We compare OpenVLA variants with parallel decoding (PD), action chunking $\left( {K = 8\text{ timesteps }}\right)$ , and continuous actions using L1 regression or diffusion objectives. For the diffusion variants, we report inference efficiency measurements with varying numbers of denoising steps at test time using the DDIM sampler [46], along with the corresponding success rates in the LIBERO-Long task suite. In the final row, we report the inference efficiency of our proposed OpenVLA-OFT formulation with additional inputs, such as wrist camera image and robot state.

<table><tr><td></td><td>Throughput $\left( \mathrm{{Hz}}\right)  \uparrow$</td><td>Latency (Sec) $\downarrow$</td><td>LIBERO-Long SR (%)</td></tr><tr><td>OpenVLA</td><td>4.2</td><td>0.2396</td><td>53.7</td></tr><tr><td>+ PD</td><td>15.9</td><td>0.0629</td><td>-</td></tr><tr><td>+ PD&AC</td><td>108.8</td><td>0.0735</td><td>86.5</td></tr><tr><td>+ PD&AC, Cont-L1</td><td>109.7</td><td>0.0729</td><td>90.7</td></tr><tr><td colspan="4">+ PD&AC, Cont-Diffusion</td></tr><tr><td>${T}_{\text{ train }} = {50},{T}_{\text{ test }} = {50}$</td><td>4.2</td><td>1.9070</td><td>91.1</td></tr><tr><td>${T}_{\text{ train }} = {50},{T}_{\text{ test }} = {10}$</td><td>19.3</td><td>0.4145</td><td>91.0</td></tr><tr><td>${T}_{\text{ train }} = {50},{T}_{\text{ test }} = 5$</td><td>35.1</td><td>0.2279</td><td>90.0</td></tr><tr><td>${T}_{\text{ train }} = {50},{T}_{\text{ test }} = 2$</td><td>80.3</td><td>0.0996</td><td>85.7</td></tr><tr><td>${T}_{\text{ train }} = {50},{T}_{\text{ test }} = 1$</td><td>109.4</td><td>0.0731</td><td>0.0</td></tr><tr><td colspan="4">+ PD&AC. Cont-L1</td></tr><tr><td>+ Additional Inputs (wrist img, proprio)</td><td>71.4</td><td>0.1120</td><td>94.5</td></tr></table>

Results in Table II show that parallel decoding reduces latency and increases throughput by $4 \times$ by replacing 7 sequential forward passes through the decoder portion of the policy with a single pass. Adding action chunking $\left( {K = 8}\right)$ increases latency by ${17}\%$ due to longer attention sequences in the decoder, but when combined with parallel decoding, it dramatically improves throughput, achieving a ${26} \times$ speedup over baseline OpenVLA. The continuous actions variant with L1 regression shows negligible difference in efficiency since the additional MLP action head adds minimal computational cost compared to the base model. The primary diffusion variant requires 50 denoising steps (since this is the number of steps specified at train time) and thus suffers from high latency. However, it still achieves the same effective throughput as baseline OpenVLA due to parallel decoding and action chunking. This means that despite longer pauses between action chunks, the 50-step diffusion variant still completes robot episodes at the same speed as the original autoregressive variant. We also test the OpenVLA diffusion variant using less than 50 denoising steps at inference time (enabled by the DDIM sampler [46]), matching state-of-the-art diffusion and flow matching methods that use 5-10 steps at inference time $\left\lbrack  {{40},{27},3}\right\rbrack$ . These configurations result in much greater inference efficiency, as shown in Table II. However, the success rates decrease with fewer denoising steps due to reduced model quality.

## D. Model Input-Output Flexibility

As explained in Section IV-B and validated by our efficiency evaluations in the prior section, parallel decoding enables OpenVLA to generate action chunks with minimal latency increase, thereby enhancing flexibility in model outputs. The significant speedup realized by parallel decoding and action chunking creates headroom for processing additional model inputs as well. We demonstrate this by fine-tuning OpenVLA with additional inputs such as robot proprioceptive state and a robot wrist-mounted camera image, which doubles the number of visual patch embeddings being passed into the language model decoder, from 256 to 512. Despite this substantial increase in input sequence length, the fine-tuned OpenVLA policy maintains high throughput (71.4 Hz) and low latency (0.112 sec), as shown in Table II.

Evaluating these policies with additional inputs on the LIBERO benchmark reveals further improvements in average success rate across all task suites (Table I). Notably, our enhanced fine-tuned OpenVLA policies outperform even the best fine-tuned ${\pi }_{0}$ policies [3,38]-which benefit from a base model with larger-scale pretraining and a more sophisticated learning objective (flow matching [25])-as well as Multimodal Diffusion Transformer (MDT) [40] and Seer [50] policies. Even with a simpler base model pretrained on less data than more recent VLAs, we find that our alternative VLA adaptation design decisions empower fine-tuned OpenVLA policies to establish a new state of the art on the LIBERO benchmark.

## E. Optimized Fine-Tuning Recipe

Based on the demonstrated improvements in task performance, inference efficiency, and model input-output flexibility, we propose an Optimized Fine-Tuning (OFT) recipe for VLA adaptation that combines three key components:

1) parallel decoding with action chunking

2) continuous action representation

3) L1 regression objective

These design choices work together to produce strong policies that can be deployed at high frequencies while maintaining algorithmic simplicity. We denote policies fine-tuned from the OpenVLA base model using our OFT recipe as OpenVLA-OFT. In Section VI, we evaluate OpenVLA-OFT's capabilities on dexterous, bimanual manipulation tasks in the real world using a high-frequency control robot.

## F. Additional Experiments

Given that the alternative fine-tuning formulation, along with additional model inputs and outputs, induces a distribution shift between the base VLA's pretraining and fine-tuning, one reasonable question is whether the base VLA's pretrained representations are helpful and have any influence on the results we have reported. We conduct an ablation study in Appendix G2 to address this question, ablating the OpenVLA pretraining phase and directly fine-tuning the underlying pretrained VLM with the OFT recipe. As shown in Table XV, the base OpenVLA pretrained representations are indeed still beneficial for robotic policy learning, as removing them leads to a 5.2% drop in average success rate (absolute) in our LIBERO evaluation suite.

(See Appendix G for other additional experiments, including scaling OpenVLA-OFT up to larger datasets-in both the LIBERO simulation setting as well as a real-world single-arm robot manipulation setting with over ${50}\mathrm{\;K}$ demonstrations from the BridgeData V2 dataset [52].)

## VI. EXPERIMENTS: ADAPTING OPENVLA TO A REAL-WORLD ALOHA ROBOT

While our experimental results in the prior section demonstrate OpenVLA-OFT's effectiveness in simulation, successful deployment in the real world, on robot platforms that differ substantially from those seen during pretraining, is crucial for showing broad applicability. We thus assess the efficacy of our optimized fine-tuning recipe on the ALOHA robot setup [56], a real bimanual manipulation platform operating at a high control frequency. We evaluate on novel dexterous manipulation tasks that have never been encountered before during OpenVLA's pretraining (which only involves single-arm robot data).

Prior works [54, 27, 3] have shown that vanilla LoRA fine-tuning with autoregressive VLAs [23] is impractical for such tasks, as its throughput (3-5 Hz for single-arm robots and even lower for bimanual tasks) falls well below the ${25} - {50}\mathrm{\;{Hz}}$ required for real-time deployment. We therefore exclude this baseline from our experiments and compare more effective methods that we discuss shortly.

In this section, we use an augmented version of our VLA fine-tuning recipe (OFT+) that additionally includes feature-wise linear modulation (FiLM) for enhanced language grounding, as described in Section IV-C. We denote the OpenVLA policy instantiated through this augmented fine-tuning recipe as OpenVLA-OFT+.

## A. ALOHA Experimental Setup

The ALOHA platform comprises two ViperX 300 S arms, three camera viewpoints (one top-down, two wrist-mounted), and robot state inputs (14-dimensional joint angles). It operates at ${25}\mathrm{\;{Hz}}$ (reduced from the original ${50}\mathrm{\;{Hz}}$ to enable faster training while still maintaining smooth robotic control), with actions representing target absolute joint angles. This setup differs significantly from OpenVLA's pretraining, which includes single-arm robot data only, a single camera viewpoint from a third-person camera, no robot state inputs, low-frequency control (3-10 Hz), and relative end-effector pose actions. The distribution shift poses a challenge to the adaptation of this model.

We design four representative tasks testing deformable object manipulation, long-horizon skills, tool usage, and language-driven control:

1) "fold shorts": Fold white shorts on a table with two consecutive bimanual folds. Training: 20 demonstrations. Evaluation: 10 trials.

![7_218_154_1368_522_0.jpg](images/7_218_154_1368_522_0.jpg)

Fig. 4: ALOHA task performance results. Comparison between policies trained from scratch (ACT, Diffusion Policy) and fine-tuned VLAs (RDT-1B, π0, OpenVLA-OFT+) across four ALOHA manipulation tasks. OpenVLA-OFT+ enhances the base model with parallel decoding, action chunking, continuous actions, L1 regression, and FiLM [37] for language grounding. Fine-tuned VLAs consistently outperform from-scratch methods, with OpenVLA-OFT+ achieving the highest average performance. Scores represent average percent completion of each task (see rubrics and detailed results in Appendix F2).

2) "fold shirt": Fold white T-shirt through multiple synchronized bimanual folds, testing contact-rich, long-horizon manipulation. Training: 30 demonstrations. Evaluation: 10 trials.

3) "scoop X into bowl": Move bowl to center of table with left arm, scoop specified ingredient ("raisins," "almonds and green M&Ms," or "pretzels") with right arm using metal spoon. Training: 45 demonstrations (15 per ingredient). Evaluation: 12 trials (4 per ingredient).

4) "put X into pot": Open pot with left arm, place specified item ("green pepper," "red pepper," or "yellow corn") with right arm, close pot. Training: 300 demonstrations (100 per object). Evaluation: 24 trials (12 in-distribution, 12 out-of-distribution).

We fine-tune OpenVLA using OFT+ on each task independently for ${50} - {150}\mathrm{\;K}$ gradient steps (total batch size 32 with 8 A100/H100-80GB GPUs) with action chunk size $K = {25}$ . At inference time, we execute the full action chunk before requerying the model for the next chunk.

## B. Methods in Comparison

The ALOHA tasks present a significant adaptation challenge for OpenVLA as the base model, given the substantial differences from its pretraining platforms in terms of control frequency, action space, and input modalities. For this reason, we compare OpenVLA-OFT+ against more recent VLAs-RDT-1B [27] and ${\pi }_{0}$ [3]-that were pretrained on bimanual manipulation data and might reasonably be expected to perform better on these downstream tasks. We evaluate these models after fine-tuning them using their authors' recommended recipes, and these methods serve as important points of comparison. Additionally, to provide comparisons with computationally efficient alternatives, we evaluate two popular imitation learning baselines: ACT [56] and Diffusion Policy [5], trained from scratch on each task.

To enable language following in these baseline methods, we use language-conditioned implementations. For ACT, we modify EfficientNet-B0 [48] to process CLIP [39] language embeddings via FiLM [37, 43].* For Diffusion Policy, we use the DROID dataset [22] implementation that conditions action denoising on DistilBERT [42] language embeddings, modified to support bimanual control and multiple image inputs.

## C. ALOHA Task Performance Results

We evaluate all methods—ACT, Diffusion Policy, RDT-1B, ${\pi }_{0}$ , and OpenVLA-OFT+—on our four ALOHA tasks. To provide fine-grained assessment, we use a predetermined rubric that assigns scores for partial task completion (see Appendix F for details). Figure 4 shows aggregate performance scores, while Figure 5 specifically tracks language following ability for the language-dependent tasks.

Performance of non-VLA baselines. The baseline methods trained from scratch show varying levels of success. ACT, while able to complete basic tasks, produces less precise actions and achieves the lowest overall performance. Diffusion Policy demonstrates stronger capabilities, matching or exceeding RDT-1B's reliability on the clothes folding and scooping tasks. However, it struggles with the "put X into pot" task which has a larger training dataset, suggesting limited scalability compared to VLA-based approaches.

Performance of fine-tuned VLAs. Fine-tuned VLA policies generally outperform the from-scratch baselines in both task execution and language following, consistent with prior findings [27, 3]. Among VLAs, we observe distinct characteristics: RDT-1B achieves good language following through its "Alternating Condition Injection" scheme [27], but shows a limitation in handling closed-loop feedback. As visualized in Figure 6, it often fails to correct mistakes in the "scoop X into bowl" task-for instance, continuing to pour ingredients into an imaginary bowl after missing the actual bowl, suggesting over-reliance on proprioceptive state over visual feedback. On the other hand, ${\pi }_{0}$ demonstrates more robust execution with smoother motions and better reactivity to feedback, often successfully recovering from initial failures (as shown in Figure 6). While its language following slightly trails RDT- 1B's, ${\pi }_{0}$ achieves better overall task completion, making it the strongest baseline. Finally, OpenVLA-OFT+ achieves the highest performance across both task execution and language following (see Figure 7 for examples of successful task rollouts). This is particularly noteworthy given that the base OpenVLA model was pretrained only on single-arm data, while RDT-1B and ${\pi }_{0}$ were pretrained on substantial bimanual datasets (6K episodes and 8K hours of bimanual data, respectively). This suggests that the fine-tuning technique can be more crucial than pretraining data coverage for downstream performance.

---

*We use this FiLM-EfficientNet implementation only for language-dependent tasks ("scoop X into bowl" and "put X into pot"). For clothes folding tasks, we use the original ResNet-18 [10] backbone as in [57].

---

![8_141_154_741_254_0.jpg](images/8_141_154_741_254_0.jpg)

Fig. 5: ALOHA language following results. Success rates in approaching language-specified target objects for language-dependent tasks. Fine-tuned VLAs follow the user's command more frequently than policies trained from scratch. OpenVLA-OFT+ shows the strongest language grounding, though removing FiLM [37] reduces success to chance level.

![8_139_601_747_779_0.jpg](images/8_139_601_747_779_0.jpg)

Fig. 6: Sample rollouts contrasting RDT-1B and ${\pi }_{0}$ error handling in ALOHA tasks. Top: In some cases, RDT-1B fails to respond to missed bowl placement, continuing to pour ingredients into empty space. Bottom: ${\pi }_{0}$ demonstrates adaptive behavior by reattempting green pepper grasp after initial failure, highlighting better visual feedback integration. See our website for videos.

![8_934_151_707_744_0.jpg](images/8_934_151_707_744_0.jpg)

Fig. 7: Sample successful OpenVLA-OFT+ rollouts on the ALOHA robot. OpenVLA-OFT+ can fold clothes, use a metal spoon to scoop and pour targeted trail mix ingredients into a bowl, and place targeted objects into a pot. See our website for videos.

Ablation study of FiLM. We evaluate the importance of FiLM in our OpenVLA-OFT+ approach by ablating it and assessing the policies' language following ability on the last two tasks, which require good language grounding for successful execution. As shown in Figure 5, language following drops to ${33}\%$ in both tasks-equal to randomly choosing the correct instruction. This demonstrates that FiLM is essential for preventing the model from overfitting to spurious visual features and ensuring proper attention to language inputs.

Please see the project website for ALOHA robot rollout videos and an in-depth qualitative analysis of all methods: https://openvla-oft.github.io

## D. ALOHA Inference Efficiency Comparisons

We evaluate inference efficiency by measuring action generation throughput and latency across 100 queries for each method. We report the results in Table III. The original OpenVLA formulation, even with just the additional wrist camera inputs, shows poor efficiency with 1.8 Hz throughput and 0.543 sec latency. In contrast, OpenVLA-OFT+ achieves 77.9 Hz throughput, though its latency is higher compared to the policies in the prior LIBERO experiments since it must process two additional input images.

Other methods demonstrate higher throughput than OpenVLA-OFT+ due to their smaller architectures: ACT (84M parameters), Diffusion Policy (157M), RDT-1B (1.2B), and ${\pi }_{0}\left( {{3.3}\mathrm{\;B}}\right)$ -while OpenVLA has 7.5B parameters. ACT achieves the highest speed by combining L1 regression-based single-pass action generation (like OpenVLA-OFT+) with its compact architecture. Also, despite its larger size, ${\pi }_{0}$ outperforms both RDT-1B and Diffusion Policy in speed thanks to its optimized JAX implementation (all other methods are implemented in PyTorch).

TABLE III: ALOHA robot inference efficiency results. Throughput and latency measurements averaged over 100 queries on an NVIDIA A100 GPU. Each query processes three ${224} \times  {224}\mathrm{{px}}$ images,14-D robot state, and a task command ("scoop raisins into bowl"). All methods use action chunk size $\mathrm{K} = {25}$ , except Diffusion Policy ( $\mathrm{K} = {24}$ , as a multiple of 4 is required) and the original OpenVLA (K=1, no chunking). RDT-1B predicts 64 actions, but we execute the first 25 only for fair comparison. All implementations use PyTorch except ${\pi }_{0}$ (JAX). Bold and underlined values show best and second-best performance.

<table><tr><td></td><td>Throughput $\left( \mathrm{{Hz}}\right)  \uparrow$</td><td>Latency (Sec) $\downarrow$</td></tr><tr><td>OpenVLA</td><td>1.8</td><td>0.543</td></tr><tr><td>OpenVLA-OFT+</td><td>77.9</td><td>0.321</td></tr><tr><td>RDT-1B</td><td>84.1</td><td>0.297</td></tr><tr><td>Diffusion Policy</td><td>267.4</td><td>0.090</td></tr><tr><td>${\pi }_{0}$</td><td>291.6</td><td>0.086</td></tr><tr><td>ACT</td><td>432.8</td><td>0.058</td></tr></table>

Notably, OpenVLA-OFT+'s throughput (77.9 Hz) approaches RDT-1B’s (84.1 Hz) despite being $7 \times$ larger, as it generates actions in a single forward pass rather than requiring multiple denoising steps as in RDT-1B.

## VII. DISCUSSION

Our study on VLA fine-tuning design decisions reveals how different components impact inference efficiency, task performance, model input-output flexibility, and language following ability. These insights lead to our Optimized Fine-Tuning (OFT) recipe, which enables effective VLA adaptation to novel robots and tasks through parallel decoding, action chunking, continuous actions, L1 regression, and (optionally) FiLM language conditioning. The success of OFT is particularly noteworthy with OpenVLA: despite having no exposure to bimanual robots or multi-view image inputs during pretraining, OpenVLA fine-tuned with OFT can adapt to such configurations and match or even outperform more recent diffusion-based VLAs $\left( {\pi }_{0}\right.$ and RDT-1B) which have encountered bimanual manipulators and multiple input images during pretraining. This demonstrates that a well-designed fine-tuning recipe can have a significant impact on final performance, and existing VLAs can be successfully adapted to new robotic systems without extensive retraining from scratch. Moreover, our results show that a simple L1 regression-based approach with a high-capacity model such as OpenVLA is quite effective for adapting to novel robots and tasks. This approach offers practical advantages over diffusion-based methods: the simpler algorithm leads to faster training convergence and inference speed while maintaining strong performance, making it particularly suitable for real-world robotics applications.

## VIII. LIMITATIONS

While our Optimized Fine-Tuning (OFT) recipe shows promise for adapting VLAs to novel robots and tasks, several important questions remain.

Handling multimodal demonstrations. Our experiments use focused demonstration datasets with a consistent strategy per task. While L1 regression may help smoothen out noise in training demonstrations by encouraging the policy to learn the median mode in demonstrated actions, it may struggle to accurately model truly multimodal action distributions where multiple valid actions exist for the same input, which may not be ideal in cases where the ability to generate alternative action sequences would be beneficial for task completion. Conversely, diffusion-based approaches may better capture such multimodality but risk overfitting to suboptimal modes in training data (see our website for discussions and video illustrations of these nuances). Understanding OFT's effectiveness with multimodal demonstrations remains an important direction for future work.

Pretraining versus fine-tuning. Our study focuses specifically on fine-tuning VLAs for downstream tasks. Whether OFT's benefits extend effectively to pretraining, or whether more expressive algorithms like diffusion are necessary for large-scale training, requires further investigation.

Inconsistent language grounding. Our ALOHA experiments reveal that OpenVLA without FiLM exhibits poor language grounding, despite showing no such issues in LIBERO simulation benchmark experiments. The source of this discrepancy-whether from the lack of bimanual data in pretraining or other factors-remains unclear and warrants further study.

## ACKNOWLEDGMENTS

We thank the Stanford Center for Research on Foundation Models (CRFM) and Stanford Institute for Human-Centered AI (HAI) for providing computational resources that supported this research. Toyota Research Institute (TRI) provided funds to assist the authors with their research, but this article solely reflects the opinions and conclusions of its authors and not TRI or any other Toyota entity. This work was also in part supported by the Robotics and AI Institute and ONR grant N00014-22-1-2621. We thank Physical Intelligence for providing beta access to the ${\pi }_{0}$ model used in our ALOHA robot evaluations. We also thank Dan Fu, Karl Pertsch, and Alec Lessing for insightful discussions which contributed to the development of this work. Lastly, we are grateful to Moritz Reuss for providing additional experimental results for MDT and engaging in helpful discussions related to this work.

## REFERENCES

[1] Michael Ahn, Anthony Brohan, Noah Brown, Yevgen Chebotar, Omar Cortes, Byron David, Chelsea Finn, Chuyuan Fu, Keerthana Gopalakrishnan, Karol Haus-man, Alex Herzog, Daniel Ho, Jasmine Hsu, Julian Ibarz, Brian Ichter, Alex Irpan, Eric Jang, Rosario Jauregui Ruano, Kyle Jeffrey, Sally Jesmonth, Nikhil J Joshi, Ryan Julian, Dmitry Kalashnikov, Yuheng Kuang, Kuang-Huei Lee, Sergey Levine, Yao Lu, Linda Luu, Carolina Parada, Peter Pastor, Jornell Quiambao, Kanishka Rao, Jarek Ret-tinghouse, Diego Reyes, Pierre Sermanet, Nicolas Sievers, Clayton Tan, Alexander Toshev, Vincent Vanhoucke, Fei Xia, Ted Xiao, Peng Xu, Sichun Xu, Mengyuan Yan, and Andy Zeng. Do as i can, not as i say: Grounding language in robotic affordances, 2022. URL https://arxiv.org/abs/2204.01691.

[2] Suneel Belkhale and Dorsa Sadigh. Minivla: A better vla with a smaller footprint, 2024. URL https://github.com/Stanford-ILIAD/ openvla-mini.

[3] Kevin Black, Noah Brown, Danny Driess, Adnan Es-mail, Michael Equi, Chelsea Finn, Niccolo Fusai, Lachy Groom, Karol Hausman, Brian Ichter, et al. pi0: A vision-language-action flow model for general robot control. arXiv preprint arXiv:2410.24164, 2024.

[4] Anthony Brohan, Noah Brown, Justice Carbajal, Yevgen Chebotar, Xi Chen, Krzysztof Choromanski, Tianli Ding, Danny Driess, Avinava Dubey, Chelsea Finn, et al. Rt-2: Vision-language-action models transfer web knowledge to robotic control. arXiv preprint arXiv:2307.15818, 2023.

[5] Cheng Chi, Zhenjia Xu, Siyuan Feng, Eric Cousineau, Yilun Du, Benjamin Burchfiel, Russ Tedrake, and Shuran Song. Diffusion policy: Visuomotor policy learning via action diffusion. The International Journal of Robotics Research, page 02783649241273668, 2023.

[6] Jiafei Duan, Wentao Yuan, Wilbert Pumacay, Yi Ru Wang, Kiana Ehsani, Dieter Fox, and Ranjay Krishna. Manipulate-anything: Automating real-world robots using vision-language models. arXiv preprint arXiv:2406.18915, 2024.

[7] Zane Durante, Bidipta Sarkar, Ran Gong, Rohan Taori, Yusuke Noda, Paul Tang, Ehsan Adeli, Shrinidhi Kow-shika Lakshmikanth, Kevin Schulman, Arnold Milstein, et al. An interactive agent foundation model. arXiv preprint arXiv:2402.05929, 2024.

[8] Andrew Sohn et al. Introducing rfm-1: Giving robots human-like reasoning capabilities, 2024. URL https://covariant.ai/insights/ introducing-rfm-1-giving-robots-human-

[9] Samir Yitzhak Gadre, Mitchell Wortsman, Gabriel Il-harco, Ludwig Schmidt, and Shuran Song. Cows on pasture: Baselines and benchmarks for language-driven zero-shot object navigation. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pages 23171-23181, 2023.

[10] Kaiming He, Xiangyu Zhang, Shaoqing Ren, and Jian Sun. Deep residual learning for image recognition. In Proceedings of the IEEE conference on computer vision and pattern recognition, pages 770-778, 2016.

[11] Dan Hendrycks and Kevin Gimpel. Gaussian error linear units (gelus). arXiv preprint arXiv:1606.08415, 2016.

[12] Jonathan Ho, Ajay Jain, and Pieter Abbeel. Denoising diffusion probabilistic models. Advances in neural information processing systems, 33:6840-6851, 2020.

[13] Zhi Hou, Tianyi Zhang, Yuwen Xiong, Hengjun Pu, Chengyang Zhao, Ronglei Tong, Yu Qiao, Jifeng Dai, and Yuntao Chen. Diffusion transformer policy: Scaling diffusion transformer for generalist vision-language-action learning, 2025. URL https://arxiv.org/ abs/2410.15959.

[14] Edward J Hu, Yelong Shen, Phillip Wallis, Zeyuan Allen-Zhu, Yuanzhi Li, Shean Wang, Lu Wang, and Weizhu Chen. Lora: Low-rank adaptation of large language models. arXiv preprint arXiv:2106.09685, 2021.

[15] Jiangyong Huang, Silong Yong, Xiaojian Ma, Xiongkun Linghu, Puhao Li, Yan Wang, Qing Li, Song-Chun Zhu, Baoxiong Jia, and Siyuan Huang. An embodied generalist agent in 3d world. In Proceedings of the International Conference on Machine Learning (ICML), 2024.

[16] Wenlong Huang, Pieter Abbeel, Deepak Pathak, and Igor Mordatch. Language models as zero-shot planners: Extracting actionable knowledge for embodied agents, 2022. URL https://arxiv.org/abs/ 2201.07207.

[17] Wenlong Huang, Fei Xia, Ted Xiao, Harris Chan, Jacky Liang, Pete Florence, Andy Zeng, Jonathan Tompson, Igor Mordatch, Yevgen Chebotar, Pierre Sermanet, Noah Brown, Tomas Jackson, Linda Luu, Sergey Levine, Karol Hausman, and Brian Ichter. Inner monologue: Embodied reasoning through planning with language models, 2022. URL https://arxiv.org/abs/2207.05608.

[18] Wenlong Huang, Chen Wang, Ruohan Zhang, Yunzhu Li, Jiajun Wu, and Li Fei-Fei. Voxposer: Composable 3d value maps for robotic manipulation with language models. arXiv preprint arXiv:2307.05973, 2023.

[19] Tobias Jülg, Wolfram Burgard, and Florian Walter. Refined policy distillation: From vla generalists to rl experts. arXiv preprint arXiv:2503.05833, 2025.

[20] Siddharth Karamcheti, Suraj Nair, Annie S. Chen, Thomas Kollar, Chelsea Finn, Dorsa Sadigh, and Percy Liang. Language-driven representation learning for robotics. ArXiv, abs/2302.12766, 2023. URL https://api.semanticscholar.org/ like- comparsing 2.5 2.5 2.5 1.5 ties/.

[21] Siddharth Karamcheti, Suraj Nair, Ashwin Balakr-ishna, Percy Liang, Thomas Kollar, and Dorsa Sadigh. Prismatic vlms: Investigating the design space of visually-conditioned language models. arXiv preprint arXiv:2402.07865, 2024.

[22] Alexander Khazatsky, Karl Pertsch, Suraj Nair, Ashwin Balakrishna, Sudeep Dasari, Siddharth Karam-cheti, Soroush Nasiriany, Mohan Kumar Srirama, Lawrence Yunliang Chen, Kirsty Ellis, et al. Droid: A large-scale in-the-wild robot manipulation dataset. arXiv preprint arXiv:2403.12945, 2024.

[23] Moo Jin Kim, Karl Pertsch, Siddharth Karamcheti, Ted Xiao, Ashwin Balakrishna, Suraj Nair, Rafael Rafailov, Ethan Foster, Grace Lam, Pannag Sanketi, et al. Openvla: An open-source vision-language-action model. arXiv preprint arXiv:2406.09246, 2024.

[24] Xinghang Li, Minghuan Liu, Hanbo Zhang, Cunjun Yu, Jie Xu, Hongtao Wu, Chilam Cheang, Ya Jing, Weinan Zhang, Huaping Liu, et al. Vision-language foundation models as effective robot imitators. arXiv preprint arXiv:2311.01378, 2023.

[25] Yaron Lipman, Ricky TQ Chen, Heli Ben-Hamu, Maximilian Nickel, and Matt Le. Flow matching for generative modeling. arXiv preprint arXiv:2210.02747, 2022.

[26] Bo Liu, Yifeng Zhu, Chongkai Gao, Yihao Feng, Qiang Liu, Yuke Zhu, and Peter Stone. Libero: Benchmarking knowledge transfer for lifelong robot learning. Advances in Neural Information Processing Systems, 36, 2024.

[27] Songming Liu, Lingxuan Wu, Bangguo Li, Hengkai Tan, Huayu Chen, Zhengyi Wang, Ke Xu, Hang Su, and Jun Zhu. Rdt-1b: a diffusion foundation model for bimanual manipulation. arXiv preprint arXiv:2410.07864, 2024.

[28] Yuejiang Liu, Jubayer Ibn Hamid, Annie Xie, Yoonho Lee, Maximilian Du, and Chelsea Finn. Bidirectional decoding: Improving action chunking via closed-loop resampling. arXiv preprint arXiv:2408.17355, 2024.

[29] Cheng Lu, Yuhao Zhou, Fan Bao, Jianfei Chen, Chongx-uan Li, and Jun Zhu. Dpm-solver++: Fast solver for guided sampling of diffusion probabilistic models. arXiv preprint arXiv:2211.01095, 2022.

[30] Yecheng Jason Ma, Shagun Sodhani, Dinesh Jayara-man, Osbert Bastani, Vikash Kumar, and Amy Zhang. Vip: Towards universal visual reward and representation via value-implicit pre-training. arXiv preprint arXiv:2210.00030, 2022.

[31] Yecheng Jason Ma, Vikash Kumar, Amy Zhang, Osbert Bastani, and Dinesh Jayaraman. Liv: Language-image representations and rewards for robotic control. In International Conference on Machine Learning, pages 23301-23320. PMLR, 2023.

[32] Arjun Majumdar, Karmesh Yadav, Sergio Arnaud, Jason Ma, Claire Chen, Sneha Silwal, Aryan Jain, Vincent-Pierre Berges, Tingfan Wu, Jay Vakil, et al. Where are we in the search for an artificial visual cortex for embodied intelligence? Advances in Neural Information Processing Systems, 36:655-677, 2023.

[33] Suraj Nair, Aravind Rajeswaran, Vikash Kumar, Chelsea Finn, and Abhinav Gupta. R3m: A universal visual representation for robot manipulation. In CoRL, 2022.

[34] Abby O'Neill, Abdul Rehman, Abhinav Gupta, Abhiram Maddukuri, Abhishek Gupta, Abhishek Padalkar, Abraham Lee, Acorn Pooley, Agrim Gupta, Ajay Mandlekar, et al. Open x-embodiment: Robotic learning datasets and rt-x models. arXiv preprint arXiv:2310.08864, 2023.

[35] Maxime Oquab, Timothée Darcet, Théo Moutakanni, Huy Vo, Marc Szafraniec, Vasil Khalidov, Pierre Fernandez, Daniel Haziza, Francisco Massa, Alaaeldin El-Nouby, et al. Dinov2: Learning robust visual features without supervision. arXiv preprint arXiv:2304.07193, 2023.

[36] Cheng Pan, Kai Junge, and Josie Hughes. Vision-language-action model and diffusion policy switching enables dexterous control of an anthropomorphic hand. arXiv preprint arXiv:2410.14022, 2024.

[37] Ethan Perez, Florian Strub, Harm De Vries, Vincent Dumoulin, and Aaron Courville. Film: Visual reasoning with a general conditioning layer. In Proceedings of the AAAI conference on artificial intelligence, volume 32, 2018.

[38] Karl Pertsch, Kyle Stachowicz, Brian Ichter, Danny Driess, Suraj Nair, Quan Vuong, Oier Mees, Chelsea Finn, and Sergey Levine. Fast: Efficient action tok-enization for vision-language-action models, 2025. URL https://arxiv.org/abs/2501.09747.

[39] Alec Radford, Jong Wook Kim, Chris Hallacy, Aditya Ramesh, Gabriel Goh, Sandhini Agarwal, Girish Sastry, Amanda Askell, Pamela Mishkin, Jack Clark, et al. Learning transferable visual models from natural language supervision. In International conference on machine learning, pages 8748-8763. PMLR, 2021.

[40] Moritz Reuss, Ömer Erdinç Yagmurlu, Fabian Wenzel, and Rudolf Lioutikov. Multimodal diffusion transformer: Learning versatile behavior from multimodal goals, 2024. URL https://arxiv.org/abs/2407.05996.

[41] Stéphane Ross, Geoffrey Gordon, and Drew Bagnell. A reduction of imitation learning and structured prediction to no-regret online learning. In Proceedings of the fourteenth international conference on artificial intelligence and statistics, pages 627-635. JMLR Workshop and Conference Proceedings, 2011.

[42] V Sanh. Distilbert, a distilled version of bert: smaller, faster, cheaper and lighter. arXiv preprint arXiv:1910.01108, 2019.

[43] Lucy Xiaoyang Shi, Zheyuan Hu, Tony Z Zhao, Archit Sharma, Karl Pertsch, Jianlan Luo, Sergey Levine, and Chelsea Finn. Yell at your robot: Improving on-the-fly from language corrections. arXiv preprint arXiv:2403.12910, 2024.

[44] Ishika Singh, Valts Blukis, Arsalan Mousavian, Ankit Goyal, Danfei Xu, Jonathan Tremblay, Dieter Fox, Jesse Thomason, and Animesh Garg. Progprompt: Generating situated robot task plans using large language models, 2022. URL https://arxiv.org/abs/2209.11302.

[45] Chan Hee Song, Jiaman Wu, Clayton Washington, Brian M. Sadler, Wei-Lun Chao, and Yu Su. Llm-planner: Few-shot grounded planning for embodied agents with large language models, 2023. URL https: //arxiv.org/abs/2212.04088.

[46] Jiaming Song, Chenlin Meng, and Stefano Ermon. Denoising diffusion implicit models. arXiv preprint arXiv:2010.02502, 2020.

[47] Austin Stone, Ted Xiao, Yao Lu, Keerthana Gopalakrish-nan, Kuang-Huei Lee, Quan Vuong, Paul Wohlhart, Sean Kirmani, Brianna Zitkovich, Fei Xia, et al. Open-world object manipulation using pre-trained vision-language models. arXiv preprint arXiv:2303.00905, 2023.

[48] Mingxing Tan and Quoc Le. Efficientnet: Rethinking model scaling for convolutional neural networks. In International conference on machine learning, pages 6105-6114. PMLR, 2019.

[49] Octo Model Team, Dibya Ghosh, Homer Walke, Karl Pertsch, Kevin Black, Oier Mees, Sudeep Dasari, Joey Hejna, Tobias Kreiman, Charles Xu, et al. Octo: An open-source generalist robot policy. arXiv preprint arXiv:2405.12213, 2024.

[50] Yang Tian, Sizhe Yang, Jia Zeng, Ping Wang, Dahua Lin, Hao Dong, and Jiangmiao Pang. Predictive inverse dynamics models are scalable learners for robotic manipulation. arXiv preprint arXiv:2412.15109, 2024.

[51] Hugo Touvron, Louis Martin, Kevin Stone, Peter Albert, Amjad Almahairi, Yasmine Babaei, Nikolay Bashlykov, Soumya Batra, Prajjwal Bhargava, Shruti Bhosale, et al. Llama 2: Open foundation and fine-tuned chat models. arXiv preprint arXiv:2307.09288, 2023.

[52] Homer Rich Walke, Kevin Black, Tony Z Zhao, Quan Vuong, Chongyi Zheng, Philippe Hansen-Estruch, Andre Wang He, Vivek Myers, Moo Jin Kim, Max Du, et al. Bridgedata v2: A dataset for robot learning at scale. In Conference on Robot Learning, pages 1723- 1736. PMLR, 2023.

[53] Wayve. Lingo-2: Driving with natural language. 2024. URL https://wayve.ai/thinking/ lingo-2-driving-with-language/.

[54] Junjie Wen, Yichen Zhu, Jinming Li, Minjie Zhu, Kun Wu, Zhiyuan Xu, Ran Cheng, Chaomin Shen, Yaxin Peng, Feifei Feng, et al. Tinyvla: Towards fast, data-efficient vision-language-action models for robotic manipulation. arXiv preprint arXiv:2409.12514, 2024.

[55] Xiaohua Zhai, Basil Mustafa, Alexander Kolesnikov, and Lucas Beyer. Sigmoid loss for language image pretraining. In Proceedings of the IEEE/CVF International Conference on Computer Vision, pages 11975-11986, 2023.

[56] Tony Z Zhao, Vikash Kumar, Sergey Levine, and Chelsea Finn. Learning fine-grained bimanual manipulation with low-cost hardware. arXiv preprint arXiv:2304.13705, 2023.

[57] Tony Z Zhao, Jonathan Tompson, Danny Driess, Pete Florence, Kamyar Ghasemipour, Chelsea Finn, and Ayzaan Wahid. Aloha unleashed: A simple recipe for robot dexterity. arXiv preprint arXiv:2410.13126, 2024.

[58] Haoyu Zhen, Xiaowen Qiu, Peihao Chen, Jincheng Yang, Xin Yan, Yilun Du, Yining Hong, and Chuang Gan. 3d-vla: 3d vision-language-action generative world model. arXiv preprint arXiv:2403.09631, 2024.

[59] Hongkuan Zhou, Xiangtong Yao, Yuan Meng, Siming Sun, Zhenshan Bing, Kai Huang, and Alois Knoll. Language-conditioned learning for robotic manipulation: A survey. arXiv preprint arXiv:2312.10807, 2023.

## APPENDIX

## A. Model Architecture Details

Base OpenVLA Architecture. OpenVLA combines a fused vision backbone (with both SigLIP [55] and DINOv2 [35] vision transformers), a Llama-2 7B language model [51], and a 3-layer MLP projector with GELU activation [11] for projecting visual features into the language embedding space.

The original model processes a single third-person image and a language instruction (e.g., "put eggplant into pot"). The fused vision encoder extracts 256 patch embeddings from each vision transformer, concatenates them along the hidden dimension, and projects them into the language embedding space. These projected features are concatenated with language embeddings along the sequence dimension before being processed by the Llama-2 decoder to output a 7-dimensional robot action representing delta end-effector pose, represented by a string of discrete action tokens.

OpenVLA-OFT architecture modifications. OpenVLA-OFT introduces six key changes:

1) processes multiple input images (e.g., third-person image plus wrist camera images) through the shared SigLIP-DINOv2 backbone

2) projects robot proprioceptive state to language embedding space via a 2-layer MLP with GELU activation

3) replaces causal attention with bidirectional attention for parallel decoding

4) substitutes the language model decoder output layer with a 4-layer MLP (ReLU activation) for generation of continuous actions (instead of discrete actions)

5) outputs chunks of K actions instead of single-timestep actions

6) (for OpenVLA-OFT+) adds FiLM [37] modules that use the average task language embedding to modulate visual features in both SigLIP and DINOv2 vision transformers (see Appendix C for details)

The complete OpenVLA-OFT+ architecture is illustrated in Figure 1.

## B. Implementation Details

1) Parallel Decoding Implementation: In the original OpenVLA autoregressive training scheme, the model receives ground-truth action tokens shifted right by one position as input (a setup known as teacher forcing). A causal attention mask ensures the model only attends to current and previous tokens. At test time, each predicted token is fed back as input for the next prediction.

For parallel decoding, we replace this input with empty action embeddings that differ only in their positional encoding values (similar to [56]). We also use a bidirectional attention mask (instead of causal), enabling the model to leverage all intermediate features non-causally when predicting each element in the action chunk.

2) Continuous Action Representations: For discrete actions, increasing the number of bins used for discretization improves precision but reduces the frequency of individual tokens in the training data, potentially hurting generalization. On the other hand, with a continuous action representation, the VLA can directly model the action distribution without lossy discretiza-tion.

Our continuous representation implementations use the following specifications:

L1 regression: The MLP action head consists of 4 layers with ReLU activation, mapping final Llama-2 decoder layer hidden states directly to continuous actions.

Diffusion: We use:

- DDIM [46] sampler with 50 diffusion timesteps

- Squared cosine beta schedule following [5, 57]

- 4-layer noise predictor with same MLP architecture as the L1 regression head

3) Input Processing Details: Passing each input image through the OpenVLA fused vision encoder produces 256 patch embeddings, which are projected to the langauge model embedding space via a 3-layer MLP with GELU activation [11]. Low-dimensional robot states are also projected to the language embedding space through a 2-layer MLP with GELU activation.

C. Feature-wise Linear Modulation (FiLM) Implementation Details

FiLM schematic. Section IV-C describes how we implement feature-wise linear modulation (FiLM) [37] for Open-VLA. Figure 8 illustrates our implementation. OpenVLA has a fused vision encoder with both SigLIP [55] and DINOv2 [35] vision transformers, and we apply FiLM to both transformers.

Design considerations. In our implementation, following Perez et al. [37], we multiply $\mathbf{F}$ by $\left( {1 + \gamma }\right)$ instead of $\gamma$ since $\gamma$ and $\beta$ are near zero at initialization. This helps preserve the visual encoder's original activations at the start of fine-tuning, minimizing perturbation in the pretrained representation.

Implementation specifics. The functions $f\left( \mathbf{x}\right)$ and $h\left( \mathbf{x}\right)$ that project language embeddings to obtain $\gamma$ and $\beta$ are implemented as simple affine transformations. Separate projectors are learned for each transformer block to allow for block-specific modulation patterns. This design enables the model to learn different modulation patterns at different levels of visual feature processing.

One might initially consider modulating each patch embedding independently, as opposed to each hidden dimension of each embedding as discussed in Section IV-C. However, our spatially-agnostic modulation approach more closely mirrors FiLM's operation in convolutional networks, where modulation applies globally across spatial dimensions since entire feature maps are scaled and shifted by individual elements of $\gamma$ and $\beta$ . This design choice better maintains the benefits of FiLM and improves the policy's language grounding substantially. We find that an alternative formulation that modulates each patch embedding independently leads to weaker language grounding.

## D. OpenVLA-OFT Hyperparameters and Training Details

OpenVLA-OFT training details for LIBERO. Hyper-parameters for OpenVLA-OFT fine-tuning on LIBERO are listed in Table IV. We train until the mean L1 loss between predicted and ground-truth normalized actions (scaled between $\left\lbrack  {-1, + 1}\right\rbrack$ ) falls below 0.01 . For faster convergence, we decay the learning rate from 5e-4 to 5e-5 after ${100}\mathrm{\;K}$ gradient steps. We evaluate checkpoints every ${50}\mathrm{\;K}$ steps, with the ${150}\mathrm{\;K}$ checkpoint achieving best performance in all task suites except for LIBERO-Goal. Note that we do not use FiLM for LIBERO experiments since the fine-tuned policies without it already demonstrate good language grounding.

![14_130_138_1537_799_0.jpg](images/14_130_138_1537_799_0.jpg)

Fig. 8: Feature-wise linear modulation (FiLM) implementation in OpenVLA's vision backbone. We integrate FiLM [37] into both SigLIP [55] and DINOv2 [35] vision transformers in OpenVLA's fused vision backbone. The average task description embedding modulates visual features through scale and shift operations at each transformer block, enhancing language-vision integration. This modification significantly improves language following in ALOHA tasks.

OpenVLA-OFT+ training details for ALOHA. Hyper-parameters for OpenVLA-OFT+ training on ALOHA tasks (with FiLM in the augmented OFT+ recipe) are shown in Table V. We maintain the same convergence criterion as in the LIBERO experiments (training until mean normalized L1 loss falls below 0.01) and similar learning rate decay strategy (again ${10} \times$ reduction, but after ${50}\mathrm{\;K}$ gradient steps instead of ${100}\mathrm{\;K}$ , since the ALOHA datasets are smaller). For the two clothes folding tasks which do not require language grounding, we still include FiLM to verify that these additional parameters do not impair task execution.

## E. Baseline Methods Hyperparameters and Training Details

ACT training details for ALOHA. Table VI lists hyper-parameters for ACT [56] trained from scratch on each task. For non-language-dependent tasks ("fold shorts", "fold shirt"), we use the default ResNet-18 [10] backbone, which does not include language conditioning. For language-dependent tasks ("scoop X into bowl", "put X into pot"), we implement EfficientNet-B0 [48] with FiLM [37], similar to [43]. While the authors of ACT recommend training for at least 5K epochs, we extend training to ${10}\mathrm{\;K} - {70}\mathrm{\;K}$ epochs per task to improve performance.

Diffusion Policy training details for ALOHA. For Diffusion Policy training, we use the DROID implementation [22], which conditions action predictions on DistilBERT [42] language embeddings of the task description. We list hyper-parameters in Table VII.

RDT-1B training details for ALOHA. Hyperparameters for RDT-1B fine-tuning are shown in Table VIII. The authors of RDT-1B recommend training for ${150}\mathrm{\;K}$ gradient steps, but we observe that training converges in significantly fewer steps since our fine-tuning datasets are much smaller than the RDT-1B fine-tuning dataset. Therefore, we observe that it is unnecessary to train for such a large amount of time. In fact, on "scoop X into bowl", the earlier 18K step checkpoint (73.3% success) outperforms the later 40K step checkpoint (70.0%) (we report the former in our ALOHA experiments).

${\pi }_{0}$ training details for ALOHA. Table IX lists hyperpa-rameters for ${\pi }_{0}$ fine-tuning. We use full fine-tuning (the default option in their codebase) and train until convergence.

## F. ALOHA Evaluation Details

1) ALOHA Task Suite Details: Below are detailed specifications for each task in our ALOHA experiments:

1. "fold shorts"

- Task: Bimanual folding of white shorts with two synchronized folds

- Dataset: 20 demonstrations (19 training, 1 validation)

- Episode length: 1000 timesteps (40 seconds)

- Evaluation: 10 trials

- Initial states: See Figure 9

## 2. "fold shirt"

- Task: Long-horizon T-shirt folding with multiple synchronized bimanual folds

- Dataset: 30 demonstrations (29 training, 1 validation)

- Episode length: 1250 timesteps (50 seconds)

- Evaluation: 10 trials

- Initial states: See Figure 10

## 3. "scoop X into bowl"

- Task: Move bowl to center, scoop specified ingredient (raisins, almonds and green M&Ms, or pretzels) into bowl

- Dataset: 45 demonstrations (15 per target; 42 training, 3 validation)

- Episode length: 900 timesteps (36 seconds)

- Evaluation: 12 trials

- Initial states: See Figure 11

## 4. "put X into pot"

- Task: Open pot, place specified item (green pepper, red pepper, or yellow corn) into pot, close pot

- Dataset: 300 demonstrations (100 per target; 285 training, 15 validation) ${}^{ \dagger  }$

- Initial variation: ${45}\mathrm{\;{cm}}$ horizontal, ${20}\mathrm{\;{cm}}$ vertical for food items; fixed pot pose

- Episode length: 400 timesteps (16 seconds)

- Evaluation: 24 trials (12 in-distribution evaluations, 12 out-of-distribution evaluations)

- Initial states: See Figures 12 (in-distribution) and 13 (out-of-distribution)

2) ALOHA Task Scoring Rubric: The scoring rubrics and detailed results for the four ALOHA tasks are shown in Tables X, XI, XII, and XIII.

## G. Additional Experiments

1) Single OpenVLA-OFT Policy for All LIBERO Task Suites Combined: In Section V and Table I, we report results with OpenVLA-OFT policies trained on each task suite independently. In this section, we assess whether our method scales to larger fine-tuning datasets by training one OpenVLA-OFT policy on all four task suites combined. As shown in Table XIV, this new policy achieves comparable average task performance as the task suite-specific policies-confirming that our method scales to larger fine-tuning datasets.

2) Ablating FiLM in LIBERO: The FiLM ablation study in Section VI suggests that FiLM is crucial for enabling strong language following in real-world ALOHA robot tasks. In this section, we assess whether FiLM is similarly important in the LIBERO simulation tasks. We train a single OpenVLA-OFT+ policy (with FiLM) on all LIBERO task suites combined (similar to the previous section) and report task performance results in Table XIV, comparing performance against the OpenVLA-OFT policy trained without FiLM. In LIBERO, FiLM leads to slightly higher average success rate, though the difference here is minor compared to the findings in the real-world ALOHA experiments, where language following is more challenging due to the reasons discussed in Section IV-C.

3) Ablating the OpenVLA Pretrained Representation: We evaluate the performance of OpenVLA-OFT policies produced by fine-tuning the underlying Prismatic VLM [21] directly on the LIBERO downstream datasets without OpenVLA's Open X-Embodiment [34] robot pretraining. This ablation study investigates whether OpenVLA's robot-pretrained representation remains valuable when subjected to a substantially different fine-tuning approach such as OFT. The results in Table XV demonstrate that the variant without the pretrained OpenVLA representation consistently underperforms compared to the full OpenVLA-OFT model, confirming the benefits of using the pretrained representation for downstream policy learning.

4) Scaling Up OpenVLA-OFT to a Larger Real-World Dataset (BridgeData V2): In Appendix G1, we observe that a single OpenVLA-OFT policy can effectively fit all four LIBERO task suite datasets combined, confirming that the proposed method scales to larger fine-tuning datasets. In this section, we scale up the fine-tuning data further and assess whether OpenVLA-OFT can also fit a real-world robotic manipulation dataset that is significantly larger and more diverse than both the LIBERO datasets and the ALOHA robot datasets discussed in Section VI. Specifically, we train OpenVLA-OFT (without FiLM) on the BridgeData V2 dataset [52], which contains 50,365 real WidowX robot demonstrations (25×more than the four LIBERO task suites combined).

We evaluate OpenVLA-OFT on a subset of BridgeData V2 WidowX robot tasks from the evaluation suite used in the original OpenVLA work [23]. This representative subset covers the four types of generalization (visual, motion, physical, semantic) as well as language grounding tasks. We compare the task performance of OpenVLA-OFT with that of the public OpenVLA checkpoint, scoring both methods using the same criteria used in the OpenVLA work. As shown in Table XVI, OpenVLA-OFT surpasses OpenVLA on average across these tasks (69.2% versus 65.8%, respectively)-confirming scalability of the proposed OFT approach to much larger and more diverse real robot datasets. Further, we observe that FiLM is not necessary for satisfactory language following in Bridge tasks, likely because the base model has shown effective language following in Bridge tasks.

---

${}^{ \ddagger  }$ Although the base OpenVLA model was already pretrained on Bridge data, we note that the model must still be fine-tuned when using the new OFT recipe since the architecture, learning algorithm, and action representation and decoding scheme have been modified significantly from the pretraining setup. In fact, the initial action regression L1 loss in the beginning of OpenVLA-OFT training on Bridge is large (roughly 0.5 when actions are normalized to the scale $\left\lbrack  {-1, + 1}\right\rbrack$ ).

†This relatively large number of demonstrations for the "put X into pot" task is not necessary for satisfactory performance. It simply reflects an earlier investigative phase of this work during which we encountered difficulties with language grounding in learned policies and initially hypothesized that increasing demonstration quantity might improve language following capabilities. However, merely expanding the training set proved insufficient for achieving satisfactory language grounding, and we discovered that additional techniques were needed for more reliable language grounding. We still decided to fine-tune on the full dataset with 300 demonstrations nonetheless.

---

TABLE IV: OpenVLA-OFT hyperparameters for LIBERO. We specify the hyperparameters for the full OpenVLA-OFT approach which includes parallel decoding, action chunking, continuous actions with L1 regression, and additional inputs (wrist camera and robot state).

<table><tr><td>hyperparameter</td><td>value</td></tr><tr><td>#GPUs</td><td>8 x NVIDIA A100 or H100 (80GB VRAM)</td></tr><tr><td>learning rate (LR)</td><td>5e-4</td></tr><tr><td>total batch size</td><td>64 (8 per GPU)</td></tr><tr><td>#train steps</td><td>150K for LIBERO-Spatial (with LR=5e-5 after 100K steps);</td></tr><tr><td></td><td>150K for LIBERO-Object (with LR=5e-5 after 100K steps); <br> 50K for LIBERO-Goal;</td></tr><tr><td></td><td>150K for LIBERO-Long (with LR=5e-5 after 100K steps)</td></tr><tr><td>input images</td><td>1 third-person camera image, 1 wrist-mounted camera image</td></tr><tr><td>input image size</td><td>224 x 224 px</td></tr><tr><td>use observation history</td><td>no (use single-step inputs)</td></tr><tr><td>LoRA rank</td><td>32</td></tr><tr><td>action chunk size</td><td>8 steps (predict 8, execute all 8 open-loop at test time)</td></tr><tr><td>use proprio (robot state)</td><td>yes</td></tr><tr><td>use FiLM</td><td>no</td></tr><tr><td>#trainable parameters</td><td>279M total (111M LoRA adapter + 151M action head + 17M proprio projector)</td></tr><tr><td>image augmentations</td><td>90% random crops, color jitter:</td></tr><tr><td></td><td>random_resized_crop=dict(scale=[0.9, 0.9], ratio=[1.0, 1.0])</td></tr><tr><td></td><td>random_brightness=[0.2]</td></tr><tr><td></td><td>random_contrast=[0.8, 1.2]</td></tr><tr><td></td><td>random_saturation=[0.8, 1.2]</td></tr><tr><td></td><td>random_hue=[0.05]</td></tr></table>

TABLE V: OpenVLA-OFT+ hyperparameters for ALOHA experiments. We specify the hyperparameters for the full OpenVLA-OFT+ approach which includes parallel decoding, action chunking, continuous actions with L1 regression, additional inputs (two wrist camera images and robot state), and FiLM.

<table><tr><td>hyperparameter</td><td>value</td></tr><tr><td>#GPUs</td><td>8 x NVIDIA A100 or H100 (80GB VRAM)</td></tr><tr><td>learning rate (LR)</td><td>5e-4</td></tr><tr><td>total batch size</td><td>32 (4 per GPU)</td></tr><tr><td>#train steps</td><td>100K for "fold shorts" (with LR=5e-5 after 50K steps);</td></tr><tr><td></td><td>70K for "fold shirt" (with LR=5e-5 after 50K steps);</td></tr><tr><td></td><td>50K for "scoop X into bowl";</td></tr><tr><td></td><td>100K for "put X into pot" (with LR=5e-5 after 50K steps);</td></tr><tr><td>input images</td><td>1 third-person camera image, 2 wrist-mounted camera images (left wrist + right wrist)</td></tr><tr><td>input image size</td><td>224 x 224 px</td></tr><tr><td>use observation history</td><td>no (use single-step inputs)</td></tr><tr><td>LoRA rank</td><td>32</td></tr><tr><td>action chunk size</td><td>25 steps (predict 25, execute all 25 open-loop at test time)</td></tr><tr><td>use proprio (robot state)</td><td>yes</td></tr><tr><td>use FiLM</td><td>yes</td></tr><tr><td>#trainable parameters</td><td>853M total (111M LoRA adapter + 269M action head + 17M proprio projector + 456M FiLM projectors)</td></tr><tr><td>image augmentations</td><td>90% random crops, color jitter: <br> random_resized_crop=dict(scale=[0.9, 0.9], ratio=[1.0, 1.0])</td></tr><tr><td></td><td>random_brightness=[0.2]</td></tr><tr><td></td><td>random_contrast=[0.8, 1.2]</td></tr><tr><td></td><td>random_saturation=[0.8, 1.2]</td></tr><tr><td></td><td>random_hue=[0.05]</td></tr></table>

TABLE VI: ACT hyperparameters for ALOHA experiments. We follow default parameters from Zhao et al. [56] with three modifications: increased batch size (8 to 64), reduced chunk size (100 to 25 to match other methods in our experiments), and EfficientNet-B0 with FiLM [37] for language-dependent tasks instead of ResNet-18. All models are trained from scratch for at least 5000 epochs, as recommended by the authors of ACT.

<table><tr><td>hyperparameter</td><td>value</td></tr><tr><td>#GPUs</td><td>1 x NVIDIA Titan RTX (24GB VRAM)</td></tr><tr><td>learning rate (LR)</td><td>1e-5</td></tr><tr><td>total batch size</td><td>64</td></tr><tr><td rowspan="4">#train "epochs"</td><td>70K for "fold shorts"</td></tr><tr><td>30K for "fold shirt"</td></tr><tr><td>20K for "scoop X into bowl"</td></tr><tr><td>10K for “put X into pot”</td></tr><tr><td>input images</td><td>1 third-person camera image, 2 wrist-mounted camera images (left wrist + right wrist)</td></tr><tr><td>input image size</td><td>224 x 224 px</td></tr><tr><td>use observation history</td><td>no (use single-step inputs)</td></tr><tr><td>action chunk size</td><td>25 steps (predict 25, execute all 25 open-loop at test time)</td></tr><tr><td>use proprio (robot state)</td><td>yes</td></tr><tr><td>image backbone</td><td>ResNet-18 for "fold shorts" and "fold shirt" tasks; <br> EfficientNet-B0 (w/ FiLM) for "scoop X into bowl" and "put X into pot" tasks</td></tr><tr><td>#trainable parameters</td><td>84M for ResNet-18 variant; 80M for EfficientNet-B0 w/ FiLM variant</td></tr></table>

TABLE VII: Diffusion Policy hyperparameters for ALOHA experiments. This configuration follows the DROID implementation [22] with two modifications: multiple input images for the ALOHA robot setup and larger image size (224 x 224 px) for fair comparison with other methods.

<table><tr><td>hyperparameter</td><td>value</td></tr><tr><td>#GPUs</td><td>1 x NVIDIA L40S (48GB VRAM)</td></tr><tr><td>learning rate (LR)</td><td>1e-4</td></tr><tr><td>total batch size</td><td>128</td></tr><tr><td>#train steps</td><td>30K for "fold shorts"</td></tr><tr><td></td><td>120K for "fold shirt"</td></tr><tr><td></td><td>80K for "scoop X into bowl"</td></tr><tr><td></td><td>40K for “put X into pot"</td></tr><tr><td>input images</td><td>1 third-person camera image, 2 wrist-mounted camera images (left wrist + right wrist)</td></tr><tr><td>input image size</td><td>224 x 224 px</td></tr><tr><td>use observation history</td><td>yes (2-step history)</td></tr><tr><td>action chunk size</td><td>24 steps (predict 24, execute all 24 open-loop at test time)</td></tr><tr><td>use proprio (robot state)</td><td>yes</td></tr><tr><td>image backbone</td><td>ResNet-50</td></tr><tr><td>#trainable parameters</td><td>157M</td></tr><tr><td>diffusion sampling algorithm</td><td>DDIM [46]</td></tr><tr><td>number of diffusion steps</td><td>100 at train time; 10 at test time (similar to [5, 22])</td></tr><tr><td>image augmentations</td><td>color jitter, 80% random crops (as specified by default by [22])</td></tr></table>

TABLE VIII: RDT-1B hyperparameters for ALOHA experiments. This configuration follows default parameters from the RDT-1B codebase [27].

<table><tr><td>hyperparameter</td><td>value</td></tr><tr><td>#GPUs</td><td>1 x NVIDIA H100 (80GB VRAM)</td></tr><tr><td>learning rate (LR)</td><td>1e-4</td></tr><tr><td>total batch size</td><td>32</td></tr><tr><td>#train steps</td><td>86K for "fold shorts"</td></tr><tr><td></td><td>30K for "fold shirt"</td></tr><tr><td></td><td>18K for "scoop X into bowl" (performs better than 40K checkpoint)</td></tr><tr><td></td><td>150K for “put X into pot”</td></tr><tr><td>input images</td><td>1 third-person camera image, 2 wrist-mounted camera images (left wrist + right wrist)</td></tr><tr><td>input image size</td><td>256 x 256 px</td></tr><tr><td>use observation history</td><td>yes (2-step history)</td></tr><tr><td>action chunk size</td><td>25 steps (predict 64 as in [27], execute 25 open-loop at test time)</td></tr><tr><td>use proprio (robot state)</td><td>yes</td></tr><tr><td>#trainable parameters</td><td>1.2B</td></tr><tr><td>diffusion sampling algorithm</td><td>DDPM [12] at train time; DPM-Solver++ [29] at test time</td></tr><tr><td>number of diffusion steps</td><td>1000 at train time; 5 at test time (same as in [27])</td></tr><tr><td>image augmentations</td><td>color jitter, image corruption (see [27] for details)</td></tr></table>

TABLE IX: ${\pi }_{0}$ hyperparameters for ALOHA experiments. This configuration follows the default settings specified in the original ${\pi }_{0}$ project codebase [3].

<table><tr><td>hyperparameter</td><td>value</td></tr><tr><td>#GPUs</td><td>1 x NVIDIA A100 or H100 (80GB VRAM)</td></tr><tr><td>learning rate (LR)</td><td>2.5e-5 peak LR (1K steps linear warmup, 29K steps cosine decay to 2.5e-6)</td></tr><tr><td>total batch size</td><td>32</td></tr><tr><td>#train steps</td><td>115K for "fold shorts"</td></tr><tr><td></td><td>75K for "fold shirt"</td></tr><tr><td></td><td>80K for "scoop X into bowl"</td></tr><tr><td></td><td>80K for "put X into pot"</td></tr><tr><td>input images</td><td>1 third-person camera image, 2 wrist-mounted camera images (left wrist + right wrist)</td></tr><tr><td>input image size</td><td>224 x 224 px</td></tr><tr><td>use observation history</td><td>no (use single-step inputs)</td></tr><tr><td>action chunk size</td><td>25 steps (predict 25, execute all 25 open-loop at test time)</td></tr><tr><td>use proprio (robot state)</td><td>yes</td></tr><tr><td>#trainable parameters</td><td>3.3B</td></tr><tr><td>diffusion sampling algorithm</td><td>flow matching [25]</td></tr><tr><td>number of integration steps</td><td>10</td></tr><tr><td>image augmentations</td><td>random crop (for non-wrist images), random rotation (for non-wrist images), color jitter: <br> augmax.RandomCrop(int(width * 0.95), int(height * 0.95)) <br> augmax.Rotate ( $\left( {-5,5}\right)$ )</td></tr><tr><td></td><td>augmax.ColorJitter(brightness=0.3, contrast=0.4, saturation=0.5)</td></tr><tr><td></td><td>(same as [3])</td></tr></table>

![18_133_912_1531_469_0.jpg](images/18_133_912_1531_469_0.jpg)

Fig. 9: Initial states for "fold shorts" task evaluations. We use the smallest variance in initial positions for this task due to the small number of training demonstrations (20) compared to other tasks. During the first eight rollouts, the shorts' position is incrementally adjusted by up to 3 cm along the vertical axis of the tabletop surface. In the final two rollouts, the shorts are rotated 10 degrees clockwise to align the bottom edge to be parallel to the tabletop's horizontal axis.

![18_134_1583_1530_471_0.jpg](images/18_134_1583_1530_471_0.jpg)

Fig. 10: Initial states for "fold shirt" task evaluations. The bottom edge of the shirt varies by 15 cm along the tabletop's vertical axis across different trials.

![19_275_456_1246_1236_0.jpg](images/19_275_456_1246_1236_0.jpg)

Fig. 11: Initial states for "scoop X into bowl" task evaluations. The green bowl's position varies by up to ${10}\mathrm{\;{cm}}$ across both vertical and horizontal table axes. Simultaneously, the metal spoon's position varies by 3 cm along the horizontal axis. Each row in this grid displays a set of three identical initial states since we rotate among three target food ingredients ("raisins", "almonds and green M&Ms", and "pretzels") with the same initial states, before moving on to the next set of initial states.

![20_276_462_1244_1230_0.jpg](images/20_276_462_1244_1230_0.jpg)

Fig. 12: Initial states for "put X into pot" task evaluations (in-distribution version). Food object positions vary by ${15}\mathrm{\;{cm}}$ vertically and ${40}\mathrm{\;{cm}}$ horizontally across trials, while the pot remains stationary. Each grid row presents three identical initial states, as we cycle through the three target objects ("green pepper", "red pepper", and "yellow corn") using the same initial configurations before we move on to the next set of initial configurations. (Refer to Figure 13 for the out-of-distribution version of this task.)

![21_278_449_1241_1231_0.jpg](images/21_278_449_1241_1231_0.jpg)

Fig. 13: Initial states for "put X into pot" task evaluations (out-of-distribution version). Unlike the in-distribution version of this task (Figure 12), this version introduces unseen green and orange bowls as distractor objects to assess robustness to novel visual inputs. Food object positions vary by ${15}\mathrm{\;{cm}}$ vertically and ${30}\mathrm{\;{cm}}$ horizontally across trials, with the pot remaining stationary. Each grid row presents three identical initial states, as we cycle through the three target objects ("green pepper", "red pepper", and "yellow corn") using the same initial configurations before we move on to the next set of initial configurations.

TABLE X: Detailed results for the "fold shorts" ALOHA task. Success is assessed using a staged scoring system, with 20 points allocated to each of five task stages. Points are awarded cumulatively, requiring successful completion of prior stages to receive a nonzero score in subsequent stages. The reported values represent the average performance across all experimental trials.

<table><tr><td></td><td>Grasped bottom edge (20 pts)</td><td>Folded in half (20 pts)</td><td>Grasped waistband (20 pts)</td><td>Folded in half again (20 pts)</td><td>Moved shorts forward (20 pts)</td><td>Total (100 pts)</td></tr><tr><td>ACT</td><td>20</td><td>20</td><td>20</td><td>20</td><td>20</td><td>100</td></tr><tr><td>Diffusion Policy</td><td>20</td><td>20</td><td>20</td><td>20</td><td>20</td><td>100</td></tr><tr><td>RDT-1B</td><td>20</td><td>20</td><td>20</td><td>20</td><td>20</td><td>100</td></tr><tr><td>${\pi }_{0}$</td><td>20</td><td>20</td><td>20</td><td>20</td><td>20</td><td>100</td></tr><tr><td>OpenVLA-OFT+</td><td>20</td><td>20</td><td>20</td><td>20</td><td>20</td><td>100</td></tr></table>

TABLE XI: Detailed results for the "fold shirt" ALOHA task. Success is assessed using a staged scoring system, with 10 points allocated to each of ten task stages. Points are awarded cumulatively, requiring successful completion of prior stages to receive a nonzero score in subsequent stages. A penalty of -10 points is applied if a large portion of the shirt sticks out after the final fold, as this is a common error for one method and is visually apparent. The reported values represent the average performance across all experimental trials.

<table><tr><td></td><td>Grasped bottom edge (10 pts)</td><td>Folded in half (10 pts)</td><td>Grasped sleeves (10 pts)</td><td>Folded sleeves over (10 pts)</td><td>Grasped bottom edge (10 pts)</td><td>Folded in half (10 pts)</td><td>Grasped right edge (10 pts)</td><td>Folded in half (10 pts)</td><td>Released shirt (10 pts)</td><td>Moved shirt forward (10 pts)</td><td>Large part sticks out (-10 pts)</td><td>Total (100 pts)</td></tr><tr><td>ACT</td><td>10</td><td>10</td><td>10</td><td>10</td><td>9</td><td>9</td><td>9</td><td>9</td><td>9</td><td>9</td><td>0</td><td>94</td></tr><tr><td>Diffusion Policy</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>0</td><td>100</td></tr><tr><td>RDT-1B</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>-4</td><td>96</td></tr><tr><td>${\pi }_{0}$</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>0</td><td>100</td></tr><tr><td>OpenVLA-OFT+</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>10</td><td>0</td><td>100</td></tr></table>

TABLE XII: Detailed results for the "scoop X into bowl" ALOHA task. Success is assessed using a staged scoring system. Points are awarded cumulatively, requiring successful completion of prior stages to receive a nonzero score in subsequent stages. Penalties of -5 points are applied if any food is spilled onto the table or if the spoon is not fully emptied during pouring. The reported values represent the average performance across all experimental trials.

<table><tr><td></td><td>Moved bowl to center (10.00 pts)</td><td>Grasped spoon (10.00 pts)</td><td>Approached correct container (20.00 pts)</td><td>Scooped correct item (20.00 pts)</td><td>Poured into bowl (20.00 pts)</td><td>Placed spoon next to bowl (20.00 pts)</td><td>Spilled food on table (-5.00 pts)</td><td>Did not empty spoon (-5.00 pts)</td><td>Total (100.00 pts)</td></tr><tr><td>ACT</td><td>9.17</td><td>9.17</td><td>18.33</td><td>15.00</td><td>15.00</td><td>5.00</td><td>-0.42</td><td>0.00</td><td>71.25</td></tr><tr><td>Diffusion Policy</td><td>10.00</td><td>10.00</td><td>18.33</td><td>15.00</td><td>13.33</td><td>13.33</td><td>-0.83</td><td>0.00</td><td>79.17</td></tr><tr><td>RDT-1B</td><td>7.50</td><td>7.50</td><td>15.00</td><td>15.00</td><td>15.00</td><td>13.33</td><td>0.00</td><td>0.00</td><td>73.33</td></tr><tr><td>${\pi }_{0}$</td><td>10.00</td><td>10.00</td><td>20.00</td><td>20.00</td><td>16.67</td><td>16.67</td><td>0.00</td><td>0.00</td><td>93.33</td></tr><tr><td>OpenVLA-OFT (no FiLM)</td><td>10.00</td><td>9.17</td><td>6.67</td><td>5.00</td><td>3.33</td><td>1.67</td><td>-0.83</td><td>0.00</td><td>35.00</td></tr><tr><td>OpenVLA-OFT+</td><td>10.00</td><td>10.00</td><td>20.00</td><td>20.00</td><td>20.00</td><td>20.00</td><td>0.00</td><td>0.00</td><td>100.00</td></tr></table>

TABLE XIII: Detailed results for the "put X into pot" ALOHA task (combined results for in-distribution and out-of-distribution evaluations). Success is assessed using a staged scoring system. Points are awarded cumulatively, requiring successful completion of prior stages to receive a nonzero score in subsequent stages. The reported values represent the average performance across all experimental trials.

<table><tr><td></td><td>Opened pot (10.00 pts)</td><td>Approached correct object (20.00 pts)</td><td>Touched correct object (10.00 pts)</td><td>Grasped correct object (20.00 pts)</td><td>Put correct object into pot (20.00 pts)</td><td>Placed lit on pot (20.00 pts)</td><td>Total (100.00 pts)</td></tr><tr><td>ACT</td><td>10.00</td><td>6.67</td><td>2.08</td><td>1.67</td><td>1.67</td><td>1.67</td><td>23.75</td></tr><tr><td>Diffusion Policy</td><td>10.00</td><td>7.50</td><td>3.33</td><td>3.33</td><td>3.33</td><td>3.33</td><td>30.83</td></tr><tr><td>RDT-1B</td><td>10.00</td><td>11.67</td><td>5.00</td><td>5.83</td><td>5.83</td><td>5.83</td><td>44.17</td></tr><tr><td>${\pi }_{0}$</td><td>10.00</td><td>10.83</td><td>4.58</td><td>6.67</td><td>5.00</td><td>5.00</td><td>42.08</td></tr><tr><td>OpenVLA-OFT (no FiLM)</td><td>10.00</td><td>6.67</td><td>3.33</td><td>5.00</td><td>3.33</td><td>3.33</td><td>31.67</td></tr><tr><td>OpenVLA-OFT+</td><td>10.00</td><td>15.83</td><td>6.25</td><td>8.33</td><td>5.83</td><td>5.00</td><td>51.25</td></tr></table>

TABLE XIV: Additional LIBERO experiments: Single policy for all LIBERO task suites and FiLM ablation study. Here we train a single policy on all four LIBERO task suites combined, without FiLM ("OpenVLA-OFT") and with FiLM ("OpenVLA-OFT+"). Policy inputs here include a third-person camera image, wrist camera image, robot proprioceptive state, and a language instruction. We observe comparable task performance when training on all task suites together versus training on each of them independently. In addition, we find that FiLM has little effect on task performance in LIBERO, given that the variant without FiLM already exhibits good language following.

<table><tr><td></td><td>Spatial SR (%)</td><td>Object SR (%)</td><td>Goal SR (%)</td><td>Long SR (%)</td><td>Average SR (%)</td></tr><tr><td>OpenVLA-OFT (1 policy per suite) (original, from Table I)</td><td>97.6</td><td>98.4</td><td>97.9</td><td>94.5</td><td>97.1</td></tr><tr><td>OpenVLA-OFT (1 policy for all 4 suites)</td><td>97.7</td><td>98.0</td><td>96.1</td><td>95.3</td><td>96.8</td></tr><tr><td>OpenVLA-OFT+ (1 policy for all 4 suites, + FiLM)</td><td>97.8</td><td>98.2</td><td>98.2</td><td>93.8</td><td>97.0</td></tr></table>

TABLE XV: Ablation experiment: Fine-tuning OpenVLA from scratch with the OFT recipe. Policy inputs here include a third-person camera image, a wrist camera image, robot proprioceptive state, and a language instruction. The from-scratch policies generally perform worse than the full OpenVLA-OFT policies, confirming that OpenVLA's pretrained representation is beneficial for downstream policy performance even when the fine-tuning recipe differs substantially from the pretraining recipe.

<table><tr><td></td><td>Spatial SR (%)</td><td>Object SR (%)</td><td>Goal SR (%)</td><td>Long SR (%)</td><td>Average SR (%)</td></tr><tr><td>OpenVLA-OFT</td><td>97.6</td><td>98.4</td><td>97.9</td><td>94.5</td><td>97.1</td></tr><tr><td>OpenVLA-OFT (scratch)</td><td>94.3</td><td>95.2</td><td>91.7</td><td>86.5</td><td>91.9</td></tr></table>

TABLE XVI: OpenVLA-OFT in BridgeData V2 WidowX robot evaluations. We use a subset of the tasks from the original OpenVLA BridgeData V2 evaluation suite, along with the corresponding scoring criteria. Each score is the average over 10 trials per task. OpenVLA-OFT surpasses OpenVLA in average task performance and even demonstrates effective language following without FiLM.

<table><tr><td>Category</td><td>Task</td><td>OpenVLA Score</td><td>OpenVLA-OFT Score</td></tr><tr><td>Visual gen</td><td>Put Eggplant into Pot</td><td>60</td><td>90</td></tr><tr><td>Motion gen</td><td>Lift Eggplant</td><td>70</td><td>60</td></tr><tr><td>Physical gen</td><td>Flip Pot Upright</td><td>90</td><td>80</td></tr><tr><td>Semantic gen</td><td>Lift White Tape</td><td>0</td><td>20</td></tr><tr><td>Language grounding</td><td>Put \{Blue Cup, Pink Cup\} on Plate</td><td>85</td><td>90</td></tr><tr><td>Language grounding</td><td>Lift \{Cheese, Red Chili Pepper\}</td><td>90</td><td>75</td></tr><tr><td colspan="2">Average</td><td>65.8</td><td>69.2</td></tr></table>