# World Model Papers

Daily updates of world model related arXiv papers.

## Papers Index

<!-- PAPERS_INDEX_START -->
- [2026-03-13](papers/2026-03-13.md) - 3 papers
- [2026-03-12](papers/2026-03-12.md) - 3 papers
- [2026-03-11](papers/2026-03-11.md) - 10 papers
- [2026-03-10](papers/2026-03-10.md) - 8 papers
- [2026-03-09](papers/2026-03-09.md) - 1 papers
- [2026-03-07](papers/2026-03-07.md) - 8 papers
- [2026-03-05](papers/2026-03-05.md) - 5 papers
- [2026-03-04](papers/2026-03-04.md) - 5 papers
- [2026-03-03](papers/2026-03-03.md) - 1 papers
- [2026-03-02](papers/2026-03-02.md) - 2 papers
- [2026-02-27](papers/2026-02-27.md) - 7 papers
- [2026-02-26](papers/2026-02-26.md) - 3 papers
- [2026-02-25](papers/2026-02-25.md) - 19 papers
- [2026-02-24](papers/2026-02-24.md) - 1 papers
- [2026-02-20](papers/2026-02-20.md) - 2 papers
- [2026-02-19](papers/2026-02-19.md) - 4 papers
- [2026-02-18](papers/2026-02-18.md) - 6 papers
- [2026-02-17](papers/2026-02-17.md) - 1 papers
- [2026-02-16](papers/2026-02-16.md) - 1 papers
- [2026-02-14](papers/2026-02-14.md) - 12 papers
<!-- PAPERS_INDEX_END -->

## Daily Papers

<!-- PAPERS_CONTENT_START -->
<details><summary><b>2026-03-13 (3 papers)</b></summary>

# arXiv World Model Papers - 2026-03-13

**Paper Count**: 3

---

## 1. Temporal Straightening for Latent Planning / 潜在规划的时间拉直

**Date**: 2026-03-12 | **arXiv**: [2603.12231v1](http://arxiv.org/abs/2603.12231v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.12231v1)

**Categories**: cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Learning good representations is essential for latent planning with world models. While pretrained visual encoders produce strong semantic visual features, they are not tailored to planning and contain information irrelevant -- or even detrimental -- to planning. Inspired by the perceptual straightening hypothesis in human visual processing, we introduce temporal straightening to improve representation learning for latent planning. Using a curvature regularizer that encourages locally straightened latent trajectories, we jointly learn an encoder and a predictor. We show that reducing curvature this way makes the Euclidean distance in latent space a better proxy for the geodesic distance and improves the conditioning of the planning objective. We demonstrate empirically that temporal straightening makes gradient-based planning more stable and yields significantly higher success rates across a suite of goal-reaching tasks.

学习良好的表示对于世界模型的潜在规划至关重要。虽然经过预训练的视觉编码器会产生强大的语义视觉特征，但它们并不是针对规划而定制的，并且包含与规划无关甚至有害的信息。受人类视觉处理中感知矫正假说的启发，我们引入时间矫正来改进潜在规划的表示学习。使用鼓励局部拉直潜在轨迹的曲率正则化器，我们共同学习编码器和预测器。我们表明，以这种方式减少曲率使得潜在空间中的欧几里得距离能够更好地代表测地距离，并改善规划目标的条件。我们凭经验证明，时间拉直使得基于梯度的规划更加稳定，并且在一系列目标达成任务中产生显着更高的成功率。

</details>

---

## 2. ARROW: Augmented Replay for RObust World models / ARROW：RObust World 模型的增强重播

**Date**: 2026-03-12 | **arXiv**: [2603.11395v1](http://arxiv.org/abs/2603.11395v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.11395v1)

**Categories**: cs.LG, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Continual reinforcement learning challenges agents to acquire new skills while retaining previously learned ones with the goal of improving performance in both past and future tasks. Most existing approaches rely on model-free methods with replay buffers to mitigate catastrophic forgetting; however, these solutions often face significant scalability challenges due to large memory demands. Drawing inspiration from neuroscience, where the brain replays experiences to a predictive World Model rather than directly to the policy, we present ARROW (Augmented Replay for RObust World models), a model-based continual RL algorithm that extends DreamerV3 with a memory-efficient, distribution-matching replay buffer. Unlike standard fixed-size FIFO buffers, ARROW maintains two complementary buffers: a short-term buffer for recent experiences and a long-term buffer that preserves task diversity through intelligent sampling. We evaluate ARROW on two challenging continual RL settings: Tasks without shared structure (Atari), and tasks with shared structure, where knowledge transfer is possible (Procgen CoinRun variants). Compared to model-free and model-based baselines with replay buffers of the same-size, ARROW demonstrates substantially less forgetting on tasks without shared structure, while maintaining comparable forward transfer. Our findings highlight the potential of model-based RL and bio-inspired approaches for continual reinforcement learning, warranting further research.

持续的强化学习要求智能体获得新技能，同时保留以前学到的技能，以提高过去和未来任务的表现。大多数现有方法依赖于具有重播缓冲区的无模型方法来减轻灾难性遗忘；然而，由于内存需求较大，这些解决方案常常面临重大的可扩展性挑战。从神经科学中汲取灵感，大脑将经验重播到预测世界模型而不是直接重播策略，我们提出了 ARROW（RObust 世界模型的增强重播），这是一种基于模型的连续 RL 算法，它通过内存高效、分布匹配的重播缓冲区扩展了 DreamerV3。与标准的固定大小 FIFO 缓冲区不同，ARROW 维护两个互补的缓冲区：一个用于最近经验的短期缓冲区和一个通过智能采样保留任务多样性的长期缓冲区。我们在两个具有挑战性的连续 RL 设置上评估 ARROW：没有共享结构的任务（Atari），以及具有共享结构的任务，其中可以进行知识转移（Procgen CoinRun 变体）。与具有相同大小的重播缓冲区的无模型和基于模型的基线相比，ARROW 在没有共享结构的任务上的遗忘显着减少，同时保持了可比较的前向传输。我们的研究结果强调了基于模型的强化学习和仿生方法在持续强化学习方面的潜力，值得进一步研究。

</details>

---

## 3. ResWM: Residual-Action World Model for Visual RL / ResWM：视觉强化学习的残差动作世界模型

**Date**: 2026-03-11 | **arXiv**: [2603.11110v1](http://arxiv.org/abs/2603.11110v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.11110v1)

**Categories**: cs.RO, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Learning predictive world models from raw visual observations is a central challenge in reinforcement learning (RL), especially for robotics and continuous control. Conventional model-based RL frameworks directly condition future predictions on absolute actions, which makes optimization unstable: the optimal action distributions are task-dependent, unknown a priori, and often lead to oscillatory or inefficient control. To address this, we introduce the Residual-Action World Model (ResWM), a new framework that reformulates the control variable from absolute actions to residual actions -- incremental adjustments relative to the previous step. This design aligns with the inherent smoothness of real-world control, reduces the effective search space, and stabilizes long-horizon planning. To further strengthen the representation, we propose an Observation Difference Encoder that explicitly models the changes between adjacent frames, yielding compact latent dynamics that are naturally coupled with residual actions. ResWM is integrated into a Dreamer-style latent dynamics model with minimal modifications and no extra hyperparameters. Both imagination rollouts and policy optimization are conducted in the residual-action space, enabling smoother exploration, lower control variance, and more reliable planning. Empirical results on the DeepMind Control Suite demonstrate that ResWM achieves consistent improvements in sample efficiency, asymptotic returns, and control smoothness, significantly surpassing strong baselines such as Dreamer and TD-MPC. Beyond performance, ResWM produces more stable and energy-efficient action trajectories, a property critical for robotic systems deployed in real-world environments. These findings suggest that residual action modeling provides a simple yet powerful principle for bridging algorithmic advances in RL with the practical requirements of robotics.

从原始视觉观察中学习预测世界模型是强化学习 (RL) 的核心挑战，特别是对于机器人和连续控制而言。传统的基于模型的强化学习框架直接以绝对动作作为未来预测的条件，这使得优化不稳定：最优动作分布依赖于任务，先验未知，并且经常导致振荡或低效控制。为了解决这个问题，我们引入了残差动作世界模型（ResWM），这是一个新框架，它将控制变量从绝对动作重新表述为残差动作——相对于上一步的增量调整。这种设计符合现实世界控制固有的平滑性，减少了有效搜索空间，并稳定了长期规划。为了进一步加强表示，我们提出了一个观察差异编码器，它显式地模拟相邻帧之间的变化，产生与残余动作自然耦合的紧凑的潜在动态。 ResWM 集成到 Dreamer 式潜在动力学模型中，只需进行最少的修改，并且无需额外的超参数。想象力的推出和策略优化都是在剩余行动空间中进行的，从而实现更顺畅的探索、更低的控制方差和更可靠的规划。 DeepMind Control Suite 上的实证结果表明，ResWM 在样本效率、渐近回报和控制平滑度方面实现了持续改进，显着超越了 Dreamer 和 TD-MPC 等强基线。除了性能之外，ResWM 还可以产生更稳定、更节能的动作轨迹，这对于在现实环境中部署的机器人系统至关重要。这些发现表明，残差动作建模提供了一种简单而强大的原理，可以将强化学习的算法进步与机器人的实际要求联系起来。

</details>

---



</details>

<details><summary><b>2026-03-12 (3 papers)</b></summary>

# arXiv World Model Papers - 2026-03-12

**Paper Count**: 3

---

## 1. PPGuide: Steering Diffusion Policies with Performance Predictive Guidance / PPGuide：通过性能预测指导指导扩散政策

**Date**: 2026-03-11 | **arXiv**: [2603.10980v1](http://arxiv.org/abs/2603.10980v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.10980v1)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Diffusion policies have shown to be very efficient at learning complex, multi-modal behaviors for robotic manipulation. However, errors in generated action sequences can compound over time which can potentially lead to failure. Some approaches mitigate this by augmenting datasets with expert demonstrations or learning predictive world models which might be computationally expensive. We introduce Performance Predictive Guidance (PPGuide), a lightweight, classifier-based framework that steers a pre-trained diffusion policy away from failure modes at inference time. PPGuide makes use of a novel self-supervised process: it uses attention-based multiple instance learning to automatically estimate which observation-action chunks from the policy's rollouts are relevant to success or failure. We then train a performance predictor on this self-labeled data. During inference, this predictor provides a real-time gradient to guide the policy toward more robust actions. We validated our proposed PPGuide across a diverse set of tasks from the Robomimic and MimicGen benchmarks, demonstrating consistent improvements in performance.

扩散策略已被证明在学习机器人操作的复杂、多模式行为方面非常有效。然而，生成的操作序列中的错误可能会随着时间的推移而复合，这可能会导致失败。一些方法通过专家演示或学习预测世界模型来增强数据集来缓解这种情况，而这可能会导致计算成本高昂。我们引入了性能预测指导 (PPGuide)，这是一种基于分类器的轻量级框架，可在推理时引导预先训练的扩散策略远离故障模式。 PPGuide 利用了一种新颖的自我监督过程：它使用基于注意力的多实例学习来自动估计策略推出中的哪些观察行动块与成功或失败相关。然后，我们根据这些自标记数据训练性能预测器。在推理过程中，该预测器提供实时梯度来指导策略采取更稳健的行动。我们在 Robomimic 和 MimicGen 基准测试中的一系列不同任务中验证了我们提出的 PPGuide，证明了性能的持续改进。

</details>

---

## 2. World Model for Battery Degradation Prediction Under Non-Stationary Aging / 非平稳老化下电池退化预测的世界模型

**Date**: 2026-03-11 | **arXiv**: [2603.10527v1](http://arxiv.org/abs/2603.10527v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.10527v1)

**Categories**: cs.LG, eess.SY

<details><summary><b>Abstract / 摘要</b></summary>

Degradation prognosis for lithium-ion cells requires forecasting the state-of-health (SOH) trajectory over future cycles. Existing data-driven approaches can produce trajectory outputs through direct regression, but lack a mechanism to propagate degradation dynamics forward in time. This paper formulates battery degradation prognosis as a world model problem, encoding raw voltage, current, and temperature time-series from each cycle into a latent state and propagating it forward via a learned dynamics transition to produce a future trajectory spanning 80 cycles. To investigate whether electrochemical knowledge improves the learned dynamics, a Single Particle Model (SPM) constraint is incorporated into the training loss. Three configurations are evaluated on the Severson LiFePO4 (LFP) dataset of 138 cells. Iterative rollout halves the trajectory forecast error compared to direct regression from the same encoder. The SPM constraint improves prediction at the degradation knee where the resistance to SOH relationship is most applicable, without changing aggregate accuracy.

锂离子电池的退化预测需要预测未来周期的健康状态 (SOH) 轨迹。现有的数据驱动方法可以通过直接回归产生轨迹输出，但缺乏及时向前传播退化动态的机制。本文将电池退化预测制定为世界模型问题，将每个周期的原始电压、电流和温度时间序列编码为潜在状态，并通过学习的动态转换向前传播，以产生跨越 80 个周期的未来轨迹。为了研究电化学知识是否改善了学习的动力学，将单粒子模型（SPM）约束纳入训练损失中。在 138 个电池的 Severson LiFePO4 (LFP) 数据集上评估了三种配置。与来自同一编码器的直接回归相比，迭代推出将轨迹预测误差减半。 SPM 约束改进了对 SOH 关系的阻力最适用的退化拐点处的预测，而不改变聚合精度。

</details>

---

## 3. PlayWorld: Learning Robot World Models from Autonomous Play / PlayWorld：从自主游戏中学习机器人世界模型

**Date**: 2026-03-09 | **arXiv**: [2603.09030v2](http://arxiv.org/abs/2603.09030v2) | **PDF**: [Link](http://arxiv.org/pdf/2603.09030v2)

**Categories**: cs.RO, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Action-conditioned video models offer a promising path to building general-purpose robot simulators that can improve directly from data. Yet, despite training on large-scale robot datasets, current state-of-the-art video models still struggle to predict physically consistent robot-object interactions that are crucial in robotic manipulation. To close this gap, we present PlayWorld, a simple, scalable, and fully autonomous pipeline for training high-fidelity video world simulators from interaction experience. In contrast to prior approaches that rely on success-biased human demonstrations, PlayWorld is the first system capable of learning entirely from unsupervised robot self-play, enabling naturally scalable data collection while capturing complex, long-tailed physical interactions essential for modeling realistic object dynamics. Experiments across diverse manipulation tasks show that PlayWorld generates high-quality, physically consistent predictions for contact-rich interactions that are not captured by world models trained on human-collected data. We further demonstrate the versatility of PlayWorld in enabling fine-grained failure prediction and policy evaluation, with up to 40% improvements over human-collected data. Finally, we demonstrate how PlayWorld enables reinforcement learning in the world model, improving policy performance by 65% in success rates when deployed in the real world.

动作条件视频模型为构建可以直接从数据中改进的通用机器人模拟器提供了一条有前途的途径。然而，尽管对大规模机器人数据集进行了训练，当前最先进的视频模型仍然难以预测在机器人操作中至关重要的物理一致的机器人与物体的交互。为了弥补这一差距，我们推出了 PlayWorld，这是一个简单、可扩展且完全自主的管道，用于通过交互体验训练高保真视频世界模拟器。与之前依赖于成功的人类演示的方法相比，PlayWorld 是第一个能够完全从无监督的机器人自我游戏中学习的系统，能够自然扩展数据收集，同时捕获对于建模真实对象动力学至关重要的复杂的长尾物理交互。跨不同操作任务的实验表明，PlayWorld 可以为接触丰富的交互生成高质量、物理一致的预测，而这些交互是根据人类收集的数据训练的世界模型无法捕获的。我们进一步证明了 PlayWorld 在实现细粒度故障预测和策略评估方面的多功能性，与人类收集的数据相比，性能提高了 40%。最后，我们演示了 PlayWorld 如何在世界模型中实现强化学习，在现实世界中部署时将策略性能提高 65% 的成功率。

</details>

---



</details>

<details><summary><b>2026-03-11 (10 papers)</b></summary>

# arXiv World Model Papers - 2026-03-11

**Paper Count**: 10

---

## 1. Towards a Neural Debugger for Python / 面向 Python 的神经调试器

**Date**: 2026-03-10 | **arXiv**: [2603.09951v1](http://arxiv.org/abs/2603.09951v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.09951v1)

**Categories**: cs.LG, cs.AI, cs.SE

<details><summary><b>Abstract / 摘要</b></summary>

Training large language models (LLMs) on Python execution traces grounds them in code execution and enables the line-by-line execution prediction of whole Python programs, effectively turning them into neural interpreters (FAIR CodeGen Team et al., 2025). However, developers rarely execute programs step by step; instead, they use debuggers to stop execution at certain breakpoints and step through relevant portions only while inspecting or modifying program variables. Existing neural interpreter approaches lack such interactive control. To address this limitation, we introduce neural debuggers: language models that emulate traditional debuggers, supporting operations such as stepping into, over, or out of functions, as well as setting breakpoints at specific source lines. We show that neural debuggers -- obtained via fine-tuning large LLMs or pre-training smaller models from scratch -- can reliably model both forward execution (predicting future states and outputs) and inverse execution (inferring prior states or inputs) conditioned on debugger actions. Evaluated on CruxEval, our models achieve strong performance on both output and input prediction tasks, demonstrating robust conditional execution modeling. Our work takes first steps towards future agentic coding systems in which neural debuggers serve as a world model for simulated debugging environments, providing execution feedback or enabling agents to interact with real debugging tools. This capability lays the foundation for more powerful code generation, program understanding, and automated debugging.

在 Python 执行轨迹上训练大型语言模型 (LLM) 可以使它们扎根于代码执行，并能够对整个 Python 程序进行逐行执行预测，从而有效地将它们转变为神经解释器（FAIR CodeGen Team 等人，2025）。然而，开发人员很少一步步执行程序；相反，他们使用调试器在某些断点处停止执行，并仅在检查或修改程序变量时逐步执行相关部分。现有的神经解释器方法缺乏这种交互控制。为了解决这个限制，我们引入了神经调试器：模拟传统调试器的语言模型，支持诸如单步进入、越过或退出函数等操作，以及在特定源代码行设置断点。我们证明，通过微调大型 LLM 或从头开始预训练较小模型获得的神经调试器可以可靠地对基于调试器操作的正向执行（预测未来状态和输出）和逆向执行（推断先前状态或输入）进行建模。在 CruxEval 上进行评估，我们的模型在输出和输入预测任务上均取得了出色的性能，展示了强大的条件执行模型。我们的工作朝着未来的代理编码系统迈出了第一步，在该系统中，神经调试器充当模拟调试环境的世界模型，提供执行反馈或使代理能够与真实的调试工具交互。此功能为更强大的代码生成、程序理解和自动调试奠定了基础。

</details>

---

## 2. RAE-NWM: Navigation World Model in Dense Visual Representation Space / RAE-NWM：密集视觉表示空间中的导航世界模型

**Date**: 2026-03-10 | **arXiv**: [2603.09241v1](http://arxiv.org/abs/2603.09241v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.09241v1)

**Categories**: cs.CV, cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Visual navigation requires agents to reach goals in complex environments through perception and planning. World models address this task by simulating action-conditioned state transitions to predict future observations. Current navigation world models typically learn state evolution under actions within the compressed latent space of a Variational Autoencoder, where spatial compression often discards fine-grained structural information and hinders precise control. To better understand the propagation characteristics of different representations, we conduct a linear dynamics probe and observe that dense DINOv2 features exhibit stronger linear predictability for action-conditioned transitions. Motivated by this observation, we propose the Representation Autoencoder-based Navigation World Model (RAE-NWM), which models navigation dynamics in a dense visual representation space. We employ a Conditional Diffusion Transformer with Decoupled Diffusion Transformer head (CDiT-DH) to model continuous transitions, and introduce a separate time-driven gating module for dynamics conditioning to regulate action injection strength during generation. Extensive evaluations show that modeling sequential rollouts in this space improves structural stability and action accuracy, benefiting downstream planning and navigation.

视觉导航要求智能体通过感知和规划在复杂环境中实现目标。世界模型通过模拟动作条件状态转换来预测未来的观察来解决此任务。当前的导航世界模型通常在变分自动编码器的压缩潜在空间内学习状态演化，其中空间压缩通常会丢弃细粒度的结构信息并阻碍精确控制。为了更好地理解不同表示的传播特性，我们进行了线性动力学探测，并观察到密集的 DINOv2 特征对动作条件转换表现出更强的线性可预测性。受这一观察的启发，我们提出了基于表示自动编码器的导航世界模型（RAE-NWM），它在密集的视觉表示空间中对导航动态进行建模。我们采用带有解耦扩散变压器头的条件扩散变压器 (CDiT-DH) 来模拟连续过渡，并引入一个单独的时间驱动选通模块进行动态调节，以在生成过程中调节动作注入强度。广泛的评估表明，对该领域的连续推出进行建模可以提高结构稳定性和行动准确性，有利于下游规划和导航。

</details>

---

## 3. Latent World Models for Automated Driving: A Unified Taxonomy, Evaluation Framework, and Open Challenges / 自动驾驶的潜在世界模型：统一的分类法、评估框架和开放挑战

**Date**: 2026-03-10 | **arXiv**: [2603.09086v1](http://arxiv.org/abs/2603.09086v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.09086v1)

**Categories**: cs.RO, cs.AI, cs.LG, cs.MA, eess.SY

<details><summary><b>Abstract / 摘要</b></summary>

Emerging generative world models and vision-language-action (VLA) systems are rapidly reshaping automated driving by enabling scalable simulation, long-horizon forecasting, and capability-rich decision making. Across these directions, latent representations serve as the central computational substrate: they compress high-dimensional multi-sensor observations, enable temporally coherent rollouts, and provide interfaces for planning, reasoning, and controllable generation. This paper proposes a unifying latent-space framework that synthesizes recent progress in world models for automated driving. The framework organizes the design space by the target and form of latent representations (latent worlds, latent actions, latent generators; continuous states, discrete tokens, and hybrids) and by structural priors for geometry, topology, and semantics. Building on this taxonomy, the paper articulates five cross-cutting internal mechanics (i.e, structural isomorphism, long-horizon temporal stability, semantic and reasoning alignment, value-aligned objectives and post-training, as well as adaptive computation and deliberation) and connects these design choices to robustness, generalization, and deployability. The work also proposes concrete evaluation prescriptions, including a closed-loop metric suite and a resource-aware deliberation cost, designed to reduce the open-loop / closed-loop mismatch. Finally, the paper identifies actionable research directions toward advancing latent world model for decision-ready, verifiable, and resource-efficient automated driving.

新兴的生成世界模型和视觉语言动作（VLA）系统通过实现可扩展的模拟、长期预测和功能丰富的决策，正在迅速重塑自动驾驶。在这些方向上，潜在表示充当中央计算基础：它们压缩高维多传感器观测结果，实现时间相干的推出，并提供用于规划、推理和可控生成的接口。本文提出了一个统一的潜在空间框架，综合了自动驾驶世界模型的最新进展。该框架通过潜在表示的目标和形式（潜在世界、潜在动作、潜在生成器；连续状态、离散标记和混合）以及几何、拓扑和语义的结构先验来组织设计空间。在此分类法的基础上，本文阐明了五种跨领域的内部机制（即结构同构、长期时间稳定性、语义和推理对齐、价值对齐目标和后训练，以及自适应计算和审议），并将这些设计选择与鲁棒性、泛化性和可部署性联系起来。这项工作还提出了具体的评估方案，包括闭环度量套件和资源感知审议成本，旨在减少开环/闭环不匹配。最后，本文确定了可操作的研究方向，以推进决策就绪、可验证和资源高效的自动驾驶的潜在世界模型。

</details>

---

## 4. PlayWorld: Learning Robot World Models from Autonomous Play / PlayWorld：从自主游戏中学习机器人世界模型

**Date**: 2026-03-09 | **arXiv**: [2603.09030v1](http://arxiv.org/abs/2603.09030v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.09030v1)

**Categories**: cs.RO, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Action-conditioned video models offer a promising path to building general-purpose robot simulators that can improve directly from data. Yet, despite training on large-scale robot datasets, current state-of-the-art video models still struggle to predict physically consistent robot-object interactions that are crucial in robotic manipulation. To close this gap, we present PlayWorld, a simple, scalable, and fully autonomous pipeline for training high-fidelity video world simulators from interaction experience. In contrast to prior approaches that rely on success-biased human demonstrations, PlayWorld is the first system capable of learning entirely from unsupervised robot self-play, enabling naturally scalable data collection while capturing complex, long-tailed physical interactions essential for modeling realistic object dynamics. Experiments across diverse manipulation tasks show that PlayWorld generates high-quality, physically consistent predictions for contact-rich interactions that are not captured by world models trained on human-collected data.We further demonstrate the versatility of PlayWorld in enabling fine-grained failure prediction and policy evaluation, with up to 40% improvements over human-collected data. Finally, we demonstrate how PlayWorld enables reinforcement learning in the world model, improving policy performance by 65% in success rates when deployed in the real world.

动作条件视频模型为构建可以直接从数据中改进的通用机器人模拟器提供了一条有前途的途径。然而，尽管对大规模机器人数据集进行了训练，当前最先进的视频模型仍然难以预测在机器人操作中至关重要的物理一致的机器人与物体的交互。为了弥补这一差距，我们推出了 PlayWorld，这是一个简单、可扩展且完全自主的管道，用于通过交互体验训练高保真视频世界模拟器。与之前依赖于成功的人类演示的方法相比，PlayWorld 是第一个能够完全从无监督的机器人自我游戏中学习的系统，能够自然扩展数据收集，同时捕获对于建模真实对象动力学至关重要的复杂的长尾物理交互。跨不同操作任务的实验表明，PlayWorld 可以针对接触丰富的交互生成高质量、物理一致的预测，而这些预测是通过人类收集的数据训练的世界模型无法捕获的。我们进一步证明了 PlayWorld 在实现细粒度故障预测和策略评估方面的多功能性，与人类收集的数据相比，性能提高了 40%。最后，我们演示了 PlayWorld 如何在世界模型中实现强化学习，在现实世界中部署时将策略性能提高 65% 的成功率。

</details>

---

## 5. MetaWorld-X: Hierarchical World Modeling via VLM-Orchestrated Experts for Humanoid Loco-Manipulation / MetaWorld-X：通过 VLM 协调专家进行人形机器人操作的分层世界建模

**Date**: 2026-03-09 | **arXiv**: [2603.08572v1](http://arxiv.org/abs/2603.08572v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.08572v1)

**Categories**: cs.RO, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Learning natural, stable, and compositionally generalizable whole-body control policies for humanoid robots performing simultaneous locomotion and manipulation (loco-manipulation) remains a fundamental challenge in robotics. Existing reinforcement learning approaches typically rely on a single monolithic policy to acquire multiple skills, which often leads to cross-skill gradient interference and motion pattern conflicts in high-degree-of-freedom systems. As a result, generated behaviors frequently exhibit unnatural movements, limited stability, and poor generalization to complex task compositions. To address these limitations, we propose MetaWorld-X, a hierarchical world model framework for humanoid control. Guided by a divide-and-conquer principle, our method decomposes complex control problems into a set of specialized expert policies (Specialized Expert Policies, SEP). Each expert is trained under human motion priors through imitation-constrained reinforcement learning, introducing biomechanically consistent inductive biases that ensure natural and physically plausible motion generation. Building upon this foundation, we further develop an Intelligent Routing Mechanism (IRM) supervised by a Vision-Language Model (VLM), enabling semantic-driven expert composition. The VLM-guided router dynamically integrates expert policies according to high-level task semantics, facilitating compositional generalization and adaptive execution in multi-stage loco-manipulation tasks.

为执行同时运动和操纵（局部操纵）的人形机器人学习自然、稳定且可组合概括的全身控制策略仍然是机器人技术中的基本挑战。现有的强化学习方法通​​常依赖于单一的整体策略来获取多种技能，这通常会导致高自由度系统中的跨技能梯度干扰和运动模式冲突。因此，生成的行为经常表现出不自然的运动、有限的稳定性以及对复杂任务组合的泛化能力差。为了解决这些限制，我们提出了 MetaWorld-X，一种用于人形控制的分层世界模型框架。在分治原则的指导下，我们的方法将复杂的控制问题分解为一组专门的专家策略（Specialized Expert Policies，SEP）。每位专家都通过模仿约束强化学习在人类运动先验条件下接受训练，引入生物力学上一致的归纳偏差，确保自然且物理上合理的运动生成。在此基础上，我们进一步开发了由视觉语言模型（VLM）监督的智能路由机制（IRM），从而实现语义驱动的专家组合。 VLM引导的路由器根据高级任务语义动态集成专家策略，促进多阶段局部操作任务中的组合泛化和自适应执行。

</details>

---

## 6. Interactive World Simulator for Robot Policy Training and Evaluation / 用于机器人政策培训和评估的交互式世界模拟器

**Date**: 2026-03-09 | **arXiv**: [2603.08546v1](http://arxiv.org/abs/2603.08546v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.08546v1)

**Categories**: cs.RO, cs.CV, cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Action-conditioned video prediction models (often referred to as world models) have shown strong potential for robotics applications, but existing approaches are often slow and struggle to capture physically consistent interactions over long horizons, limiting their usefulness for scalable robot policy training and evaluation. We present Interactive World Simulator, a framework for building interactive world models from a moderate-sized robot interaction dataset. Our approach leverages consistency models for both image decoding and latent-space dynamics prediction, enabling fast and stable simulation of physical interactions. In our experiments, the learned world models produce interaction-consistent pixel-level predictions and support stable long-horizon interactions for more than 10 minutes at 15 FPS on a single RTX 4090 GPU. Our framework enables scalable demonstration collection solely within the world models to train state-of-the-art imitation policies. Through extensive real-world evaluation across diverse tasks involving rigid objects, deformable objects, object piles, and their interactions, we find that policies trained on world-model-generated data perform comparably to those trained on the same amount of real-world data. Additionally, we evaluate policies both within the world models and in the real world across diverse tasks, and observe a strong correlation between simulated and real-world performance. Together, these results establish the Interactive World Simulator as a stable and physically consistent surrogate for scalable robotic data generation and faithful, reproducible policy evaluation.

动作条件视频预测模型（通常称为世界模型）在机器人应用中显示出强大的潜力，但现有方法通常速度缓慢，并且难以捕获长范围内物理一致的交互，从而限制了它们在可扩展机器人策略训练和评估中的有用性。我们提出了交互式世界模拟器，这是一个用于从中等大小的机器人交互数据集构建交互式世界模型的框架。我们的方法利用一致性模型进行图像解码和潜在空间动态预测，从而实现快速稳定的物理交互模拟。在我们的实验中，学习的世界模型可生成交互一致的像素级预测，并在单个 RTX 4090 GPU 上以 15 FPS 的速度支持稳定的长视野交互超过 10 分钟。我们的框架可以仅在世界模型中进行可扩展的演示收集，以训练最先进的模仿策略。通过对涉及刚性物体、可变形物体、物体堆及其相互作用的各种任务进行广泛的现实世界评估，我们发现根据世界模型生成的数据训练的策略与根据相同数量的现实世界数据训练的策略的表现相当。此外，我们还评估了世界模型中和现实世界中不同任务的政策，并观察到模拟和现实世界表现之间的强相关性。总之，这些结果使交互式世界模拟器成为稳定且物理一致的替代品，用于可扩展的机器人数据生成和忠实、可重复的政策评估。

</details>

---

## 7. AtomVLA: Scalable Post-Training for Robotic Manipulation via Predictive Latent World Models / AtomVLA：通过预测潜在世界模型进行机器人操作的可扩展后训练

**Date**: 2026-03-09 | **arXiv**: [2603.08519v1](http://arxiv.org/abs/2603.08519v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.08519v1)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Vision-Language-Action (VLA) models demonstrate remarkable potential for generalizable robotic manipulation. The execution of complex multi-step behaviors in VLA models can be improved by robust instruction grounding, a critical component for effective control. However, current paradigms predominantly rely on coarse, high-level task instructions during supervised fine-tuning. This instruction grounding gap leaves models without explicit intermediate guidance, leading to severe compounding errors in long-horizon tasks. Therefore, bridging this instruction gap and providing scalable post-training for VLA models is urgent. To tackle this problem, we propose \method, the first subtask-aware VLA framework integrated with a scalable offline post-training pipeline. Our framework leverages a large language model to decompose high-level demonstrations into fine-grained atomic subtasks. This approach utilizes a pretrained predictive world model to score candidate action chunks against subtask goals in the latent space, mitigating error accumulation while significantly improving long-horizon robustness. Furthermore, this approach enables highly efficient Group Relative Policy Optimization without the prohibitive expenses associated with online rollouts on physical robots. Extensive simulations validate that our AtomVLA maintains strong robustness under perturbations. When evaluated against fundamental baseline models, it achieves an average success rate of 97.0\% on the LIBERO benchmark and 48.0\% on the LIBERO-PRO benchmark. Finally, experiments conducted in the real world using the Galaxea R1 Lite platform confirm its broad applicability across diverse tasks, especially long-horizon tasks. All datasets, checkpoints, and code will be released to the public domain following the acceptance of this work for future research.

视觉-语言-动作（VLA）模型展示了通用机器人操作的巨大潜力。 VLA 模型中复杂多步行为的执行可以通过强大的指令基础来改进，这是有效控制的关键组成部分。然而，当前的范例在监督微调期间主要依赖于粗略的高级任务指令。这种指令基础差距使模型没有明确的中间指导，导致长期任务中出现严重的复合错误。因此，弥合这一指令差距并为 VLA 模型提供可扩展的后训练迫在眉睫。为了解决这个问题，我们提出了 \method，这是第一个与可扩展的离线后训练管道集成的子任务感知 VLA 框架。我们的框架利用大型语言模型将高级演示分解为细粒度的原子子任务。这种方法利用预训练的预测世界模型根据潜在空间中的子任务目标对候选动作块进行评分，减少错误积累，同时显着提高长期鲁棒性。此外，这种方法可以实现高效的组相对策略优化，而无需与物理机器人在线部署相关的高昂费用。大量的模拟验证了我们的 AtomVLA 在扰动下保持了很强的鲁棒性。当根据基本基线模型进行评估时，它在 LIBERO 基准上的平均成功率为 97.0%，在 LIBERO-PRO 基准上的平均成功率为 48.0%。最后，使用 Galaxea R1 Lite 平台在现实世界中进行的实验证实了其在各种任务（尤其是长视野任务）中的广泛适用性。在接受这项工作以供未来研究后，所有数据集、检查点和代码都将发布到公共领域。

</details>

---

## 8. STRIDE: Structured Lagrangian and Stochastic Residual Dynamics via Flow Matching / STRIDE：通过流量匹配实现结构化拉格朗日和随机残差动力学

**Date**: 2026-03-09 | **arXiv**: [2603.08478v1](http://arxiv.org/abs/2603.08478v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.08478v1)

**Categories**: cs.RO, cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Robotic systems operating in unstructured environments must operate under significant uncertainty arising from intermittent contacts, frictional variability, and unmodeled compliance. While recent model-free approaches have demonstrated impressive performance, many deployment settings still require predictive models that support planning, constraint handling, and online adaptation. Analytical rigid-body models provide strong physical structure but often fail to capture complex interaction effects, whereas purely data-driven models may violate physical consistency, exhibit data bias, and accumulate long-horizon drift. In this work, we propose STRIDE, a dynamics learning framework that explicitly separates conservative rigid-body mechanics from uncertain, effectively stochastic non-conservative interaction effects. The structured component is modeled using a Lagrangian Neural Network (LNN) to preserve energy-consistent inertial dynamics, while residual interaction forces are represented using Conditional Flow Matching (CFM) to capture multi-modal interaction phenomena. The two components are trained jointly end-to-end, enabling the model to retain physical structure while representing complex stochastic behavior. We evaluate STRIDE on systems of increasing complexity, including a pendulum, the Unitree Go1 quadruped, and the Unitree G1 humanoid. Results show 20% reduction in long-horizon prediction error and 30% reduction in contact force prediction error compared to deterministic residual baselines, supporting more reliable model-based control in uncertain robotic environments.

在非结构化环境中运行的机器人系统必须在由间歇性接触、摩擦变化和未建模的合规性引起的显着不确定性下运行。虽然最近的无模型方法已经表现出令人印象深刻的性能，但许多部署设置仍然需要支持规划、约束处理和在线适应的预测模型。分析刚体模型提供了强大的物理结构，但通常无法捕获复杂的交互效应，而纯粹的数据驱动模型可能会违反物理一致性、表现出数据偏差并累积长范围漂移。在这项工作中，我们提出了 STRIDE，一种动力学学习框架，它明确地将保守的刚体力学与不确定的、有效随机的非保守相互作用效应分开。结构化组件使用拉格朗日神经网络 (LNN) 进行建模，以保持能量一致的惯性动力学，而残余相互作用力则使用条件流匹配 (CFM) 来表示，以捕获多模态相互作用现象。这两个组件进行端到端联合训练，使模型能够保留物理结构，同时表示复杂的随机行为。我们在复杂性不断增加的系统上评估 STRIDE，包括钟摆、Unitree Go1 四足动物和 Unitree G1 人形机器人。结果显示，与确定性残差基线相比，长视野预测误差减少了 20%，接触力预测误差减少了 30%，支持在不确定的机器人环境中进行更可靠的基于模型的控制。

</details>

---

## 9. Integrating Lagrangian Neural Networks into the Dyna Framework for Reinforcement Learning / 将拉格朗日神经网络集成到 Dyna 强化学习框架中

**Date**: 2026-03-09 | **arXiv**: [2603.08468v1](http://arxiv.org/abs/2603.08468v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.08468v1)

**Categories**: eess.SY, cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Model-based reinforcement learning (MBRL) is sample-efficient but depends on the accuracy of the learned dynamics, which are often modeled using black-box methods that do not adhere to physical laws. Those methods tend to produce inaccurate predictions when presented with data that differ from the original training set. In this work, we employ Lagrangian neural networks (LNNs), which enforce an underlying Lagrangian structure to train the model within a Dyna-based MBRL framework. Furthermore, we train the LNN using stochastic gradient-based and state-estimation-based optimizers to learn the network's weights. The state-estimation-based method converges faster than the stochastic gradient-based method during neural network training. Simulation results are provided to illustrate the effectiveness of the proposed LNN-based Dyna framework for MBRL.

基于模型的强化学习 (MBRL) 具有样本效率，但取决于所学习动态的准确性，而动态学习通常使用不遵守物理定律的黑盒方法进行建模。当提供与原始训练集不同的数据时，这些方法往往会产生不准确的预测。在这项工作中，我们采用拉格朗日神经网络 (LNN)，它强制使用底层拉格朗日结构来在基于 Dyna 的 MBRL 框架内训练模型。此外，我们使用基于随机梯度和基于状态估计的优化器来训练 LNN，以学习网络的权重。在神经网络训练期间，基于状态估计的方法比基于随机梯度的方法收敛得更快。仿真结果说明了所提出的基于 LNN 的 Dyna 框架的 MBRL 的有效性。

</details>

---

## 10. The Boiling Frog Threshold: Criticality and Blindness in World Model-Based Anomaly Detection Under Gradual Drift / 温水煮青蛙阈值：渐进漂移下基于世界模型的异常检测的临界性和盲目性

**Date**: 2026-03-09 | **arXiv**: [2603.08455v1](http://arxiv.org/abs/2603.08455v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.08455v1)

**Categories**: cs.AI, cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

When an RL agent's observations are gradually corrupted, at what drift rate does it "wake up" -- and what determines this boundary? We study world model-based self-monitoring under continuous observation drift across four MuJoCo environments, three detector families (z-score, variance, percentile), and three model capacities. We find that (1) a sharp detection threshold $\varepsilon^*$ exists universally: below it, drift is absorbed as normal variation; above it, detection occurs rapidly. The threshold's existence and sigmoid shape are invariant across all detector families and model capacities, though its position depends on the interaction between detector sensitivity, noise floor structure, and environment dynamics. (2) Sinusoidal drift is completely undetectable by all detector families -- including variance and percentile detectors with no temporal smoothing -- establishing this as a world model property rather than a detector artifact. (3) Within each environment, $\varepsilon^*$ follows a power law in detector parameters ($R^2 = 0.89$-$0.97$), but cross-environment prediction fails ($R^2 = 0.45$), revealing that the missing variable is environment-specific dynamics structure $\partial \mathrm{PE}/\partial\varepsilon$. (4) In fragile environments, agents collapse before any detector can fire ("collapse before awareness"), creating a fundamentally unmonitorable failure mode. Our results reframe $\varepsilon^*$ from an emergent world model property to a three-way interaction between noise floor, detector, and environment dynamics, providing a more defensible and empirically grounded account of self-monitoring boundaries in RL agents.

当强化学习智能体的观察逐渐被破坏时，它会以什么漂移率“醒来”——什么决定了这个边界？我们在四个 MuJoCo 环境、三个探测器系列（z 分数、方差、百分位数）和三个模型容量的连续观察漂移下研究基于世界模型的自我监控。我们发现（1）普遍存在一个尖锐的检测阈值$\varepsilon^*$：低于它，漂移被吸收为正常变化；在其上方，检测速度很快。尽管阈值的位置取决于探测器灵敏度、本底噪声结构和环境动力学之间的相互作用，但阈值的存在和 S 形形状在所有探测器系列和模型容量中都是不变的。 (2) 所有检测器系列（包括没有时间平滑的方差和百分位检测器）完全无法检测到正弦漂移——将其确定为世界模型属性而不是检测器伪影。 (3) 在每个环境中，$\varepsilon^*$ 的探测器参数遵循幂律 ($R^2 = 0.89$-$0.97$)，但跨环境预测失败 ($R^2 = 0.45$)，表明缺失的变量是环境特定的动力学结构 $\partial\mathrm{PE}/\partial\varepsilon$。 (4) 在脆弱的环境中，代理在任何探测器启动之前就崩溃了（“在意识到之前崩溃”），从而产生了一种根本上无法监控的故障模式。我们的结果将 $\varepsilon^*$ 从新兴的世界模型属性重新构建为本底噪声、检测器和环境动力学之间的三向交互，为 RL 智能体的自我监控边界提供了更有说服力和基于经验的解释。

</details>

---



</details>

<details><summary><b>2026-03-10 (8 papers)</b></summary>

# arXiv World Model Papers - 2026-03-10

**Paper Count**: 8

---

## 1. Multifingered force-aware control for humanoid robots / 人形机器人的多指力感知控制

**Date**: 2026-03-09 | **arXiv**: [2603.08142v1](http://arxiv.org/abs/2603.08142v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.08142v1)

**Categories**: cs.RO

**Code**: https://github.com/hsp-iit/multifingered-force-aware-control.

<details><summary><b>Abstract / 摘要</b></summary>

In this paper, we address force-aware control and force distribution in robotic platforms with multi-fingered hands. Given a target goal and force estimates from tactile sensors, we design a controller that adapts the motion of the torso, arm, wrist, and fingers, redistributing forces to maintain stable contact with objects of varying mass distribution or unstable contacts. To estimate forces, we collect a dataset of tactile signals and ground-truth force measurements using five Xela magnetic sensors interacting with indenters, and train force estimators. We then introduce a model-based control scheme that minimizes the distance between the Center of Pressure (CoP) and the centroid of the fingertips contact polygon. Since our method relies on estimated forces rather than raw tactile signals, it has the potential to be applied to any sensor capable of force estimation. We validate our framework on a balancing task with five objects, achieving a $82.7\%$ success rate, and further evaluate it in multi-object scenarios, achieving $80\%$ accuracy. Code and data can be found here https://github.com/hsp-iit/multifingered-force-aware-control.

在本文中，我们解决了多指手机器人平台中的力感知控制和力分布问题。给定目标目标和触觉传感器的力估计，我们设计了一个控制器，可以适应躯干、手臂、手腕和手指的运动，重新分配力以保持与不同质量分布或不稳定接触的物体的稳定接触。为了估计力，我们使用五个与压头交互的 Xela 磁性传感器收集触觉信号和地面真实力测量数据集，并训练力估计器。然后，我们引入一种基于模型的控制方案，该方案可以最小化压力中心 (CoP) 与指尖接触多边形质心之间的距离。由于我们的方法依赖于估计的力而不是原始的触觉信号，因此它有可能应用于任何能够估计力的传感器。我们在五个对象的平衡任务上验证了我们的框架，实现了 82.7\%$ 的成功率，并在多对象场景中进一步评估它，实现了 $80\%$ 的准确率。代码和数据可以在这里找到：https://github.com/hsp-iit/multifingered-force-aware-control。

</details>

---

## 2. Model-based Offline RL via Robust Value-Aware Model Learning with Implicitly Differentiable Adaptive Weighting / 基于模型的离线强化学习，通过具有隐式可微自适应权重的鲁棒价值感知模型学习

**Date**: 2026-03-09 | **arXiv**: [2603.08118v1](http://arxiv.org/abs/2603.08118v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.08118v1)

**Categories**: cs.LG

**Code**: https://github.com/zq2r/ROMI.git.

<details><summary><b>Abstract / 摘要</b></summary>

Model-based offline reinforcement learning (RL) aims to enhance offline RL with a dynamics model that facilitates policy exploration. However, \textit{model exploitation} could occur due to inevitable model errors, degrading algorithm performance. Adversarial model learning offers a theoretical framework to mitigate model exploitation by solving a maximin formulation. Within such a paradigm, RAMBO~\citep{rigter2022rambo} has emerged as a representative and most popular method that provides a practical implementation with model gradient. However, we empirically reveal that severe Q-value underestimation and gradient explosion can occur in RAMBO with only slight hyperparameter tuning, suggesting that it tends to be overly conservative and suffers from unstable model updates. To address these issues, we propose \textbf{RO}bust value-aware \textbf{M}odel learning with \textbf{I}mplicitly differentiable adaptive weighting (ROMI). Instead of updating the dynamics model with model gradient, ROMI introduces a novel robust value-aware model learning approach. This approach requires the dynamics model to predict future states with values close to the minimum Q-value within a scale-adjustable state uncertainty set, enabling controllable conservatism and stable model updates. To further improve out-of-distribution (OOD) generalization during multi-step rollouts, we propose implicitly differentiable adaptive weighting, a bi-level optimization scheme that adaptively achieves dynamics- and value-aware model learning. Empirical results on D4RL and NeoRL datasets show that ROMI significantly outperforms RAMBO and achieves competitive or superior performance compared to other state-of-the-art methods on datasets where RAMBO typically underperforms. Code is available at https://github.com/zq2r/ROMI.git.

基于模型的离线强化学习（RL）旨在通过促进政策探索的动态模型来增强离线强化学习。然而，由于不可避免的模型错误，\textit{模型利用}可能会发生，从而降低算法性能。对抗性模型学习提供了一个理论框架，通过求解最大最小公式来减轻模型利用。在这样的范例中，RAMBO~\citep{rigter2022rambo} 已成为一种具有代表性和最流行的方法，它提供了模型梯度的实际实现。然而，我们的经验表明，RAMBO 仅需要轻微的超参数调整，就会出现严重的 Q 值低估和梯度爆炸，这表明它往往过于保守，并且模型更新不稳定。为了解决这些问题，我们提出使用 \textbf{I} 隐式可微自适应权重（ROMI）进行 \textbf{RO}bust 值感知 \textbf{M} 模型学习。 ROMI 没有使用模型梯度来更新动态模型，而是引入了一种新颖的鲁棒价值感知模型学习方法。这种方法要求动态模型在可调节的状态不确定性集中以接近最小 Q 值的值来预测未来状态，从而实现可控的保守性和稳定的模型更新。为了进一步提高多步推出期间的分布外（OOD）泛化，我们提出了隐式可微自适应加权，这是一种自适应实现动态和价值感知模型学习的双层优化方案。 D4RL 和 NeoRL 数据集上的实证结果表明，ROMI 显着优于 RAMBO，并且与 RAMBO 通常表现不佳的数据集上的其他最先进方法相比，取得了有竞争力或优越的性能。代码可在 https://github.com/zq2r/ROMI.git 获取。

</details>

---

## 3. ConflictBench: Evaluating Human-AI Conflict via Interactive and Visually Grounded Environments / ConflictBench：通过交互式和视觉基础环境评估人类与人工智能的冲突

**Date**: 2026-03-09 | **arXiv**: [2603.08024v1](http://arxiv.org/abs/2603.08024v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.08024v1)

**Categories**: cs.CL

<details><summary><b>Abstract / 摘要</b></summary>

As large language models (LLMs) evolve into autonomous agents capable of acting in open-ended environments, ensuring behavioral alignment with human values becomes a critical safety concern. Existing benchmarks, focused on static, single-turn prompts, fail to capture the interactive and multi-modal nature of real-world conflicts. We introduce ConflictBench, a benchmark for evaluating human-AI conflict through 150 multi-turn scenarios derived from prior alignment queries. ConflictBench integrates a text-based simulation engine with a visually grounded world model, enabling agents to perceive, plan, and act under dynamic conditions. Empirical results show that while agents often act safely when human harm is immediate, they frequently prioritize self-preservation or adopt deceptive strategies in delayed or low-risk settings. A regret test further reveals that aligned decisions are often reversed under escalating pressure, especially with visual input. These findings underscore the need for interaction-level, multi-modal evaluation to surface alignment failures that remain hidden in conventional benchmarks.

随着大型语言模型（LLM）发展成为能够在开放环境中行动的自主代理，确保行为与人类价值观一致成为一个关键的安全问题。现有的基准侧重于静态、单轮提示，无法捕捉现实世界冲突的交互性和多模式本质。我们引入了 ConflictBench，这是一个通过先前对齐查询得出的 150 个多回合场景来评估人类与人工智能冲突的基准。 ConflictBench 将基于文本的模拟引擎与基于视觉的世界模型集成在一起，使代理能够在动态条件下感知、计划和行动。实证结果表明，虽然代理人在人类受到直接伤害时通常会采取安全行动，但他们经常会优先考虑自我保护或在延迟或低风险环境中采取欺骗策略。后悔测试进一步表明，在不断升级的压力下，尤其是在视觉输入的情况下，一致的决定常常会被逆转。这些发现强调需要对传统基准中隐藏的表面对准故障进行交互级、多模式评估。

</details>

---

## 4. Long-Short Term Agents for Pure-Vision Bronchoscopy Robotic Autonomy / 纯视觉支气管镜机器人自主的长期和短期代理

**Date**: 2026-03-09 | **arXiv**: [2603.07909v1](http://arxiv.org/abs/2603.07909v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.07909v1)

**Categories**: cs.RO, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Accurate intraoperative navigation is essential for robot-assisted endoluminal intervention, but remains difficult because of limited endoscopic field of view and dynamic artifacts. Existing navigation platforms often rely on external localization technologies, such as electromagnetic tracking or shape sensing, which increase hardware complexity and remain vulnerable to intraoperative anatomical mismatch. We present a vision-only autonomy framework that performs long-horizon bronchoscopic navigation using preoperative CT-derived virtual targets and live endoscopic video, without external tracking during navigation. The framework uses hierarchical long-short agents: a short-term reactive agent for continuous low-latency motion control, and a long-term strategic agent for decision support at anatomically ambiguous points. When their recommendations conflict, a world-model critic predicts future visual states for candidate actions and selects the action whose predicted state best matches the target view. We evaluated the system in a high-fidelity airway phantom, three ex vivo porcine lungs, and a live porcine model. The system reached all planned segmental targets in the phantom, maintained 80\% success to the eighth generation ex vivo, and achieved in vivo navigation performance comparable to the expert bronchoscopist. These results support the preclinical feasibility of sensor-free autonomous bronchoscopic navigation.

准确的术中导航对于机器人辅助腔内干预至关重要，但由于内窥镜视野有限和动态伪影，仍然很困难。现有的导航平台通常依赖于外部定位技术，例如电磁跟踪或形状传感，这增加了硬件复杂性，并且仍然容易受到术中解剖不匹配的影响。我们提出了一种仅视觉自主框架，该框架使用术前 CT 衍生的虚拟目标和实时内窥镜视频执行长视野支气管镜导航，在导航过程中无需外部跟踪。该框架使用分层的长短代理：用于连续低延迟运动控制的短期反应代理，以及用于在解剖学模糊点上提供决策支持的长期策略代理。当他们的建议发生冲突时，世界模型评论家会预测候选动作的未来视觉状态，并选择预测状态与目标视图最匹配的动作。我们在高保真气道模型、三个离体猪肺和活体猪模型中评估了该系统。该系统达到了体模中所有计划的分段目标，保持了第八代离体80％的成功率，并实现了与专家支气管镜医师相当的体内导航性能。这些结果支持无传感器自主支气管镜导航的临床前可行性。

</details>

---

## 5. MWM: Mobile World Models for Action-Conditioned Consistent Prediction / MWM：用于动作条件一致预测的移动世界模型

**Date**: 2026-03-08 | **arXiv**: [2603.07799v1](http://arxiv.org/abs/2603.07799v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.07799v1)

**Categories**: cs.CV, cs.RO

**Code**: https://github.com/AIGeeksGroup/MWM.

<details><summary><b>Abstract / 摘要</b></summary>

World models enable planning in imagined future predicted space, offering a promising framework for embodied navigation. However, existing navigation world models often lack action-conditioned consistency, so visually plausible predictions can still drift under multi-step rollout and degrade planning. Moreover, efficient deployment requires few-step diffusion inference, but existing distillation methods do not explicitly preserve rollout consistency, creating a training-inference mismatch. To address these challenges, we propose MWM, a mobile world model for planning-based image-goal navigation. Specifically, we introduce a two-stage training framework that combines structure pretraining with Action-Conditioned Consistency (ACC) post-training to improve action-conditioned rollout consistency. We further introduce Inference-Consistent State Distillation (ICSD) for few-step diffusion distillation with improved rollout consistency. Our experiments on benchmark and real-world tasks demonstrate consistent gains in visual fidelity, trajectory accuracy, planning success, and inference efficiency. Code: https://github.com/AIGeeksGroup/MWM. Website: https://aigeeksgroup.github.io/MWM.

世界模型可以在想象的未来预测空间中进行规划，为实体导航提供一个有前景的框架。然而，现有的导航世界模型通常缺乏动作条件的一致性，因此视觉上合理的预测仍然可能在多步骤部署下发生漂移并降低规划质量。此外，有效的部署需要几步扩散推理，但现有的蒸馏方法没有明确地保持部署一致性，从而导致训练与推理不匹配。为了应对这些挑战，我们提出了 MWM，一种用于基于规划的图像目标导航的移动世界模型。具体来说，我们引入了一个两阶段训练框架，将结构预训练与动作条件一致性（ACC）训练后相结合，以提高动作条件推出一致性。我们进一步引入推理一致状态蒸馏（ICSD），用于少步扩散蒸馏，并提高推出一致性。我们对基准和现实世界任务的实验证明了视觉保真度、轨迹准确性、规划成功和推理效率方面的持续收益。代码：https://github.com/AIGeeksGroup/MWM。网站：https://aigeeksgroup.github.io/MWM。

</details>

---

## 6. DreamSAC: Learning Hamiltonian World Models via Symmetry Exploration / DreamSAC：通过对称性探索学习哈密顿世界模型

**Date**: 2026-03-08 | **arXiv**: [2603.07545v1](http://arxiv.org/abs/2603.07545v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.07545v1)

**Categories**: cs.CV, cs.AI, cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Learned world models excel at interpolative generalization but fail at extrapolative generalization to novel physical properties. This limitation arises because they learn statistical correlations rather than the environment's underlying generative rules, such as physical invariances and conservation laws. We argue that learning these invariances is key to robust extrapolation. To achieve this, we first introduce \textbf{Symmetry Exploration}, an unsupervised exploration strategy where an agent is intrinsically motivated by a Hamiltonian-based curiosity bonus to actively probe and challenge its understanding of conservation laws, thereby collecting physically informative data. Second, we design a Hamiltonian-based world model that learns from the collected data, using a novel self-supervised contrastive objective to identify the invariant physical state from raw, view-dependent pixel observations. Our framework, \textbf{DreamSAC}, trained on this actively curated data, significantly outperforms state-of-the-art baselines in 3D physics simulations on tasks requiring extrapolation.

学习世界模型擅长插值概括，但无法对新的物理属性进行外推概括。出现这种限制是因为它们学习的是统计相关性，而不是环境的潜在生成规则，例如物理不变性和守恒定律。我们认为学习这些不变性是稳健外推的关键。为了实现这一目标，我们首先引入 \textbf{Symmetry Exploration}，这是一种无监督的探索策略，其中代理本质上受到基于哈密顿量的好奇心奖励的激励，主动探索和挑战其对守恒定律的理解，从而收集物理信息数据。其次，我们设计了一个基于哈密顿量的世界模型，该模型从收集的数据中学习，使用新颖的自监督对比目标从原始的、依赖于视图的像素观察中识别不变的物理状态。我们的框架 \textbf{DreamSAC} 在这些主动整理的数据上进行了训练，在需要外推的任务上显着优于 3D 物理模拟中最先进的基线。

</details>

---

## 7. Underwater Embodied Intelligence for Autonomous Robots: A Constraint-Coupled Perspective on Planning, Control, and Deployment / 自主机器人的水下具身智能：规划、控制和部署的约束耦合视角

**Date**: 2026-03-08 | **arXiv**: [2603.07393v1](http://arxiv.org/abs/2603.07393v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.07393v1)

**Categories**: cs.RO, eess.SY

<details><summary><b>Abstract / 摘要</b></summary>

Autonomous underwater robots are increasingly deployed for environmental monitoring, infrastructure inspection, subsea resource exploration, and long-horizon exploration. Yet, despite rapid advances in learning-based planning and control, reliable autonomy in real ocean environments remains fundamentally constrained by tightly coupled physical limits. Hydrodynamic uncertainty, partial observability, bandwidth-limited communication, and energy scarcity are not independent challenges; they interact within the closed perception-planning-control loop and often amplify one another over time. This Review develops a constraint-coupled perspective on underwater embodied intelligence, arguing that planning and control must be understood within tightly coupled sensing, communication, coordination, and resource constraints in real ocean environments. We synthesize recent progress in reinforcement learning, belief-aware planning, hybrid control, multi-robot coordination, and foundation-model integration through this embodied perspective. Across representative application domains, we show how environmental monitoring, inspection, exploration, and cooperative missions expose distinct stress profiles of cross-layer coupling. To unify these observations, we introduce a cross-layer failure taxonomy spanning epistemic, dynamic, and coordination breakdowns, and analyze how errors cascade across autonomy layers under uncertainty. Building on this structure, we outline research directions toward physics-grounded world models, certifiable learning-enabled control, communication-aware coordination, and deployment-aware system design. By internalizing constraint coupling rather than treating it as an external disturbance, underwater embodied intelligence may evolve from performance-driven adaptation toward resilient, scalable, and verifiable autonomy under real ocean conditions.

自主水下机器人越来越多地应用于环境监测、基础设施检查、海底资源勘探和长视距勘探。然而，尽管基于学习的规划和控制取得了快速进展，但真实海洋环境中的可靠自主仍然从根本上受到紧密耦合的物理限制的限制。流体动力学的不确定性、部分可观测性、带宽有限的通信和能源稀缺并不是独立的挑战；它们在封闭的感知-规划-控制循环中相互作用，并且常常随着时间的推移而相互放大。本综述对水下体现智能提出了约束耦合的观点，认为必须在真实海洋环境中紧密耦合的传感、通信、协调和资源约束范围内理解规划和控制。我们通过这一具体视角综合了强化学习、信念感知规划、混合控制、多机器人协调和基础模型集成方面的最新进展。在代表性的应用领域中，我们展示了环境监测、检查、探索和合作任务如何揭示跨层耦合的不同应力分布。为了统一这些观察结果，我们引入了涵盖认知故障、动态故障和协调故障的跨层故障分类法，并分析了在不确定性下错误如何跨自治层级联。在此结构的基础上，我们概述了基于物理的世界模型、可认证的学习控制、通信感知协调和部署感知系统设计的研究方向。通过内化约束耦合而不是将其视为外部干扰，水下体现智能可以从性能驱动的适应演变为真实海洋条件下的弹性、可扩展和可验证的自主性。

</details>

---

## 8. Kinematics-Aware Latent World Models for Data-Efficient Autonomous Driving / 用于数据高效自动驾驶的运动学感知潜在世界模型

**Date**: 2026-03-07 | **arXiv**: [2603.07264v1](http://arxiv.org/abs/2603.07264v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.07264v1)

**Categories**: cs.RO, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Data-efficient learning remains a central challenge in autonomous driving due to the high cost and safety risks of large-scale real-world interaction. Although world-model-based reinforcement learning enables policy optimization through latent imagination, existing approaches often lack explicit mechanisms to encode spatial and kinematic structure essential for driving tasks. In this work, we build upon the Recurrent State-Space Model (RSSM) and propose a kinematics-aware latent world model framework for autonomous driving. Vehicle kinematic information is incorporated into the observation encoder to ground latent transitions in physically meaningful motion dynamics, while geometry-aware supervision regularizes the RSSM latent state to capture task-relevant spatial structure beyond pixel reconstruction. The resulting structured latent dynamics improve long-horizon imagination fidelity and stabilize policy optimization. Experiments in a driving simulation benchmark demonstrate consistent gains over both model-free and pixel-based world-model baselines in terms of sample efficiency and driving performance. Ablation studies further verify that the proposed design enhances spatial representation quality within the latent space. These results suggest that integrating kinematic grounding into RSSM-based world models provides a scalable and physically grounded paradigm for autonomous driving policy learning.

由于大规模现实世界交互的高成本和安全风险，数据高效学习仍然是自动驾驶的核心挑战。尽管基于世界模型的强化学习可以通过潜在想象力实现策略优化，但现有方法通常缺乏明确的机制来编码驾驶任务所必需的空间和运动结构。在这项工作中，我们以循环状态空间模型（RSSM）为基础，提出了一种用于自动驾驶的运动学感知潜在世界模型框架。车辆运动学信息被纳入观察编码器中，以在物理上有意义的运动动力学中实现潜在转变，而几何感知监督则规范 RSSM 潜在状态，以捕获超越像素重建的任务相关空间结构。由此产生的结构化潜在动态提高了长期想象力的保真度并稳定了政策优化。驾驶模拟基准测试中的实验表明，在样本效率和驾驶性能方面，与无模型和基于像素的世界模型基准相比，具有一致的增益。消融研究进一步验证了所提出的设计增强了潜在空间内的空间表示质量。这些结果表明，将运动学接地集成到基于 RSSM 的世界模型中，为自动驾驶政策学习提供了可扩展且物理接地的范例。

</details>

---



</details>

<details><summary><b>2026-03-09 (1 papers)</b></summary>

# arXiv World Model Papers - 2026-03-09

**Paper Count**: 1

---

## 1. Uncertainty-Aware Adaptive Dynamics For Underwater Vehicle-Manipulator Robots / 水下车辆机械手机器人的不确定性感知自适应动力学

**Date**: 2026-03-06 | **arXiv**: [2603.06548v1](http://arxiv.org/abs/2603.06548v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.06548v1)

**Categories**: cs.RO, eess.SY

<details><summary><b>Abstract / 摘要</b></summary>

Accurate and adaptive dynamic models are critical for underwater vehicle-manipulator systems where hydrodynamic effects induce time-varying parameters. This paper introduces a novel uncertainty-aware adaptive dynamics model framework that remains linear in lumped vehicle and manipulator parameters, and embeds convex physical consistency constraints during online estimation. Moving horizon estimation is used to stack horizon regressors, enforce realizable inertia, damping, friction, and hydrostatics, and quantify uncertainty from parameter evolution. Experiments on a BlueROV2 Heavy with a 4-DOF manipulator demonstrate rapid convergence and calibrated predictions. Manipulator fits achieve R2 = 0.88 to 0.98 with slopes near unity, while vehicle surge, heave, and roll are reproduced with good fidelity under stronger coupling and noise. Median solver time is approximately 0.023 s per update, confirming online feasibility. A comparison against a fixed parameter model shows consistent reductions in MAE and RMSE across degrees of freedom. Results indicate physically plausible parameters and confidence intervals with near 100% coverage, enabling reliable feedforward control and simulation in underwater environments.

准确和自适应的动态模型对于水下航行器操纵器系统至关重要，其中水动力效应会引起时变参数。本文介绍了一种新颖的不确定性感知自适应动力学模型框架，该框架在集总车辆和机械臂参数中保持线性，并在在线估计期间嵌入凸物理一致性约束。移动地平线估计用于堆叠地平线回归量，强制实现可实现的惯性、阻尼、摩擦力和流体静力学，并量化参数演化的不确定性。在带有 4-DOF 机械臂的 BlueROV2 Heavy 上进行的实验证明了快速收敛和校准预测。机械手拟合实现 R2 = 0.88 至 0.98，斜率接近一致，而车辆波动、升沉和侧倾在更强的耦合和噪声下以良好的保真度再现。每次更新求解器时间中值约为 0.023 秒，证实了在线可行性。与固定参数模型的比较表明，MAE 和 RMSE 在各个自由度上均一致降低。结果表明物理上合理的参数和置信区间具有接近 100% 的覆盖率，可在水下环境中实现可靠的前馈控制和模拟。

</details>

---



</details>

<details><summary><b>2026-03-07 (8 papers)</b></summary>

# arXiv World Model Papers - 2026-03-07

**Paper Count**: 8

---

## 1. Planning in 8 Tokens: A Compact Discrete Tokenizer for Latent World Model / 8 个令牌的规划：用于潜在世界模型的紧凑型离散令牌生成器

**Date**: 2026-03-05 | **arXiv**: [2603.05438v1](http://arxiv.org/abs/2603.05438v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.05438v1)

**Categories**: cs.CV, cs.AI, cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

World models provide a powerful framework for simulating environment dynamics conditioned on actions or instructions, enabling downstream tasks such as action planning or policy learning. Recent approaches leverage world models as learned simulators, but its application to decision-time planning remains computationally prohibitive for real-time control. A key bottleneck lies in latent representations: conventional tokenizers encode each observation into hundreds of tokens, making planning both slow and resource-intensive. To address this, we propose CompACT, a discrete tokenizer that compresses each observation into as few as 8 tokens, drastically reducing computational cost while preserving essential information for planning. An action-conditioned world model that occupies CompACT tokenizer achieves competitive planning performance with orders-of-magnitude faster planning, offering a practical step toward real-world deployment of world models.

世界模型提供了一个强大的框架，用于模拟以行动或指令为条件的环境动态，从而实现行动规划或政策学习等下游任务。最近的方法利用世界模型作为学习模拟器，但其在决策时规划中的应用在计算上仍然无法实现实时控制。一个关键瓶颈在于潜在表示：传统的标记器将每个观察结果编码为数百个标记，使得规划既缓慢又占用资源。为了解决这个问题，我们提出了 CompACT，这是一种离散标记器，可将每个观察值压缩为少至 8 个标记，从而大大降低计算成本，同时保留规划所需的基本信息。占用 CompACT 标记器的动作条件世界模型通过速度快几个数量级的规划实现了具有竞争力的规划性能，为世界模型的实际部署迈出了实际的一步。

</details>

---

## 2. BLINK: Behavioral Latent Modeling of NK Cell Cytotoxicity / BLINK：NK 细胞细胞毒性的行为潜在模型

**Date**: 2026-03-05 | **arXiv**: [2603.05110v1](http://arxiv.org/abs/2603.05110v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.05110v1)

**Categories**: cs.CV, cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Machine learning models of cellular interaction dynamics hold promise for understanding cell behavior. Natural killer (NK) cell cytotoxicity is a prominent example of such interaction dynamics and is commonly studied using time-resolved multi-channel fluorescence microscopy. Although tumor cell death events can be annotated at single frames, NK cytotoxic outcome emerges over time from cellular interactions and cannot be reliably inferred from frame-wise classification alone. We introduce BLINK, a trajectory-based recurrent state-space model that serves as a cell world model for NK-tumor interactions. BLINK learns latent interaction dynamics from partially observed NK-tumor interaction sequences and predicts apoptosis increments that accumulate into cytotoxic outcomes. Experiments on long-term time-lapse NK-tumor recordings show improved cytotoxic outcome detection and enable forecasting of future outcomes, together with an interpretable latent representation that organizes NK trajectories into coherent behavioral modes and temporally structured interaction phases. BLINK provides a unified framework for quantitative evaluation and structured modeling of NK cytotoxic behavior at the single-cell level.

细胞相互作用动力学的机器学习模型有望理解细胞行为。自然杀伤 (NK) 细胞的细胞毒性是这种相互作用动力学的一个突出例子，通常使用时间分辨多通道荧光显微镜进行研究。尽管肿瘤细胞死亡事件可以在单帧上注释，但 NK 细胞毒性结果会随着时间的推移从细胞相互作用中出现，并且不能仅从逐帧分类中可靠地推断出来。我们引入了 BLINK，这是一种基于轨迹的循环状态空间模型，可用作 NK 与肿瘤相互作用的细胞世界模型。 BLINK 从部分观察到的 NK 与肿瘤相互作用序列中学习潜在的相互作用动态，并预测累积成细胞毒性结果的细胞凋亡增量。长期延时 NK 肿瘤记录的实验表明，细胞毒性结果检测得到改善，并能够预测未来结果，以及可解释的潜在表示，将 NK 轨迹组织成连贯的行为模式和时间结构化的相互作用阶段。 BLINK 为单细胞水平的 NK 细胞毒性行为的定量评估和结构化建模提供了统一的框架。

</details>

---

## 3. Enhancing Zero-shot Commonsense Reasoning by Integrating Visual Knowledge via Machine Imagination / 通过机器想象力整合视觉知识来增强零样本常识推理

**Date**: 2026-03-05 | **arXiv**: [2603.05040v1](http://arxiv.org/abs/2603.05040v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.05040v1)

**Categories**: cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Recent advancements in zero-shot commonsense reasoning have empowered Pre-trained Language Models (PLMs) to acquire extensive commonsense knowledge without requiring task-specific fine-tuning. Despite this progress, these models frequently suffer from limitations caused by human reporting biases inherent in textual knowledge, leading to understanding discrepancies between machines and humans. To bridge this gap, we introduce an additional modality to enrich the reasoning capabilities of PLMs. We propose Imagine (Machine Imagination-based Reasoning), a novel zero-shot commonsense reasoning framework that supplements textual inputs with visual signals from machine-generated images. Specifically, we enhance PLMs with the ability to imagine by embedding an image generator directly into the reasoning pipeline. To facilitate effective utilization of this imagined visual context, we construct synthetic datasets designed to emulate visual question-answering scenarios. Through comprehensive evaluations on multiple commonsense reasoning benchmarks, we demonstrate that Imagine substantially outperforms existing zero-shot approaches and even surpasses advanced large language models. These results underscore the capability of machine imagination to mitigate reporting bias and significantly enhance the generalization ability of commonsense reasoning models

零样本常识推理的最新进展使预训练语言模型 (PLM) 能够获取广泛的常识知识，而无需针对特定任务进行微调。尽管取得了这些进展，但这些模型经常受到文本知识中固有的人类报告偏见所造成的限制，导致机器和人类之间的理解差异。为了弥补这一差距，我们引入了一种额外的模式来丰富 PLM 的推理能力。我们提出 Imagine（基于机器想象力的推理），这是一种新颖的零样本常识推理框架，它用来自机器生成图像的视觉信号补充文本输入。具体来说，我们通过将图像生成器直接嵌入到推理管道中来增强 PLM 的想象能力。为了促进有效利用这种想象的视觉上下文，我们构建了旨在模拟视觉问答场景的合成数据集。通过对多个常识推理基准的综合评估，我们证明 Imagine 大大优于现有的零样本方法，甚至超越了先进的大型语言模型。这些结果强调了机器想象力减轻报告偏差并显着增强常识推理模型的泛化能力的能力

</details>

---

## 4. Data-Driven Control of a Magnetically Actuated Fish-Like Robot / 磁驱动鱼状机器人的数据驱动控制

**Date**: 2026-03-05 | **arXiv**: [2603.04787v1](http://arxiv.org/abs/2603.04787v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.04787v1)

**Categories**: cs.RO, eess.SY

<details><summary><b>Abstract / 摘要</b></summary>

Magnetically actuated fish-like robots offer promising solutions for underwater exploration due to their miniaturization and agility; however, precise control remains a significant challenge because of nonlinear fluid dynamics, flexible fin hysteresis, and the variable-duration control steps inherent to the actuation mechanism. This paper proposes a comprehensive data-driven control framework to address these complexities without relying on analytical modeling. Our methodology comprises three core components: 1) developing a forward dynamics model (FDM) using a neural network trained on real-world experimental data to capture state transitions under varying time steps; 2) integrating this FDM into a gradient-based model predictive control (G-MPC) architecture to optimize control inputs for path following; and 3) applying imitation learning to approximate the G-MPC policy, thereby reducing the computational cost for real-time implementation. We validate the approach through simulations utilizing the identified dynamics model. The results demonstrate that the G-MPC framework achieves accurate path convergence with minimal root mean square error (RMSE), and the imitation learning controller (ILC) effectively replicates this performance. This study highlights the potential of data-driven control strategies for the precise navigation of miniature, fish-like soft robots.

磁驱动类鱼机器人由于其小型化和敏捷性，为水下探索提供了有前景的解决方案；然而，由于非线性流体动力学、灵活的翅片迟滞以及致动机构固有的可变持续时间控制步骤，精确控制仍然是一个重大挑战。本文提出了一个全面的数据驱动控制框架来解决这些复杂性，而不依赖于分析模型。我们的方法包括三个核心组成部分：1）使用经过真实实验数据训练的神经网络开发正向动力学模型（FDM），以捕获不同时间步长下的状态转换； 2) 将此 FDM 集成到基于梯度的模型预测控制 (G-MPC) 架构中，以优化路径跟踪的控制输入； 3）应用模仿学习来逼近G-MPC策略，从而降低实时实现的计算成本。我们通过利用已确定的动力学模型进行模拟来验证该方法。结果表明，G-MPC 框架以最小均方根误差 (RMSE) 实现了精确的路径收敛，并且模仿学习控制器 (ILC) 有效地复制了这种性能。这项研究强调了数据驱动控制策略在微型鱼状软机器人精确导航方面的潜力。

</details>

---

## 5. Probabilistic Dreaming for World Models / 世界模型的概率梦想

**Date**: 2026-03-05 | **arXiv**: [2603.04715v1](http://arxiv.org/abs/2603.04715v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.04715v1)

**Categories**: cs.LG, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

"Dreaming" enables agents to learn from imagined experiences, enabling more robust and sample-efficient learning of world models. In this work, we consider innovations to the state-of-the-art Dreamer model using probabilistic methods that enable: (1) the parallel exploration of many latent states; and (2) maintaining distinct hypotheses for mutually exclusive futures while retaining the desirable gradient properties of continuous latents. Evaluating on the MPE SimpleTag domain, our method outperforms standard Dreamer with a 4.5% score improvement and 28% lower variance in episode returns. We also discuss limitations and directions for future work, including how optimal hyperparameters (e.g. particle count K) scale with environmental complexity, and methods to capture epistemic uncertainty in world models.

“梦想”使代理能够从想象的经验中学习，从而实现对世界模型的更稳健和样本效率的学习。在这项工作中，我们考虑使用概率方法对最先进的 Dreamer 模型进行创新，这些方法能够：（1）并行探索许多潜在状态； (2) 为互斥的未来维持不同的假设，同时保留连续潜伏的理想梯度特性。在 MPE SimpleTag 域上进行评估，我们的方法优于标准 Dreamer，得分提高了 4.5%，且剧集回报方差降低了 28%。我们还讨论了未来工作的局限性和方向，包括最佳超参数（例如粒子计数 K）如何随环境复杂性变化，以及捕获世界模型中认知不确定性的方法。

</details>

---

## 6. Latent Particle World Models: Self-supervised Object-centric Stochastic Dynamics Modeling / 潜在粒子世界模型：以对象为中心的自监督随机动力学建模

**Date**: 2026-03-04 | **arXiv**: [2603.04553v1](http://arxiv.org/abs/2603.04553v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.04553v1)

**Categories**: cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

We introduce Latent Particle World Model (LPWM), a self-supervised object-centric world model scaled to real-world multi-object datasets and applicable in decision-making. LPWM autonomously discovers keypoints, bounding boxes, and object masks directly from video data, enabling it to learn rich scene decompositions without supervision. Our architecture is trained end-to-end purely from videos and supports flexible conditioning on actions, language, and image goals. LPWM models stochastic particle dynamics via a novel latent action module and achieves state-of-the-art results on diverse real-world and synthetic datasets. Beyond stochastic video modeling, LPWM is readily applicable to decision-making, including goal-conditioned imitation learning, as we demonstrate in the paper. Code, data, pre-trained models and video rollouts are available: https://taldatech.github.io/lpwm-web

我们引入了潜在粒子世界模型（LPWM），这是一种自我监督的以对象为中心的世界模型，可扩展到现实世界的多对象数据集并适用于决策。 LPWM 直接从视频数据中自主发现关键点、边界框和对象掩模，使其能够在无需监督的情况下学习丰富的场景分解。我们的架构纯粹通过视频进行端到端训练，并支持对动作、语言和图像目标的灵活调节。 LPWM 通过新颖的潜在动作模块对随机粒子动力学进行建模，并在各种现实世界和合成数据集上取得了最先进的结果。正如我们在论文中所演示的，除了随机视频建模之外，LPWM 还很容易应用于决策，包括目标条件模仿学习。代码、数据、预训练模型和视频可供使用：https://taldatech.github.io/lpwm-web

</details>

---

## 7. World Properties without World Models: Recovering Spatial and Temporal Structure from Co-occurrence Statistics in Static Word Embeddings / 没有世界模型的世界属性：从静态词嵌入中的共现统计中恢复时空结构

**Date**: 2026-03-04 | **arXiv**: [2603.04317v1](http://arxiv.org/abs/2603.04317v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.04317v1)

**Categories**: cs.CL, cs.AI, cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Recent work interprets the linear recoverability of geographic and temporal variables from large language model (LLM) hidden states as evidence for world-like internal representations. We test a simpler possibility: that much of the relevant structure is already latent in text itself. Applying the same class of ridge regression probes to static co-occurrence-based embeddings (GloVe and Word2Vec), we find substantial recoverable geographic signal and weaker but reliable temporal signal, with held-out R^2 values of 0.71-0.87 for city coordinates and 0.48-0.52 for historical birth years. Semantic-neighbor analyses and targeted subspace ablations show that these signals depend strongly on interpretable lexical gradients, especially country names and climate-related vocabulary. These findings suggest that ordinary word co-occurrence preserves richer spatial, temporal, and environmental structure than is often assumed, revealing a remarkable and underappreciated capacity of simple static embeddings to preserve world-shaped structure from text alone. Linear probe recoverability alone therefore does not establish a representational move beyond text.

最近的工作将大语言模型（LLM）隐藏状态中地理和时间变量的线性可恢复性解释为类似世界的内部表示的证据。我们测试了一种更简单的可能性：大部分相关结构已经隐藏在文本本身中。将同一类岭回归探针应用于基于静态共现的嵌入（GloVe 和 Word2Vec），我们发现大量可恢复的地理信号和较弱但可靠的时间信号，城市坐标的 R^2 值为 0.71-0.87，历史出生年份的 R^2 值为 0.48-0.52。语义邻居分析和有针对性的子空间消融表明，这些信号强烈依赖于可解释的词汇梯度，尤其是国名和气候相关词汇。这些发现表明，普通的单词共现保留了比通常假设的更丰富的空间、时间和环境结构，揭示了简单静态嵌入仅从文本中保留世界形状结构的显着且未被充分认识的能力。因此，仅线性探针的可恢复性并不能建立超越文本的代表性移动。

</details>

---

## 8. IPD: Boosting Sequential Policy with Imaginary Planning Distillation in Offline Reinforcement Learning / IPD：通过离线强化学习中的想象规划蒸馏来促进顺序策略

**Date**: 2026-03-04 | **arXiv**: [2603.04289v1](http://arxiv.org/abs/2603.04289v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.04289v1)

**Categories**: cs.LG, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Decision transformer based sequential policies have emerged as a powerful paradigm in offline reinforcement learning (RL), yet their efficacy remains constrained by the quality of static datasets and inherent architectural limitations. Specifically, these models often struggle to effectively integrate suboptimal experiences and fail to explicitly plan for an optimal policy. To bridge this gap, we propose \textbf{Imaginary Planning Distillation (IPD)}, a novel framework that seamlessly incorporates offline planning into data generation, supervised training, and online inference. Our framework first learns a world model equipped with uncertainty measures and a quasi-optimal value function from the offline data. These components are utilized to identify suboptimal trajectories and augment them with reliable, imagined optimal rollouts generated via Model Predictive Control (MPC). A Transformer-based sequential policy is then trained on this enriched dataset, complemented by a value-guided objective that promotes the distillation of the optimal policy. By replacing the conventional, manually-tuned return-to-go with the learned quasi-optimal value function, IPD improves both decision-making stability and performance during inference. Empirical evaluations on the D4RL benchmark demonstrate that IPD significantly outperforms several state-of-the-art value-based and transformer-based offline RL methods across diverse tasks.

基于决策转换器的顺序策略已成为离线强化学习 (RL) 中的强大范例，但其功效仍然受到静态数据集质量和固有架构限制的限制。具体来说，这些模型通常难以有效地整合次优经验，并且无法明确规划最优策略。为了弥补这一差距，我们提出了 \textbf{想象规划蒸馏（IPD）}，这是一种新颖的框架，可以将离线规划无缝地融入数据生成、监督训练和在线推理中。我们的框架首先从离线数据中学习一个配备了不确定性度量和准最优价值函数的世界模型。这些组件用于识别次优轨迹，并通过模型预测控制 (MPC) 生成可靠的、想象的最佳推出来增强它们。然后，在这个丰富的数据集上训练基于 Transformer 的顺序策略，并辅以促进最优策略精炼的价值引导目标。通过用学习的准最优值函数取代传统的手动调整的返回，IPD 提高了推理过程中决策的稳定性和性能。对 D4RL 基准的实证评估表明，IPD 在不同的任务中显着优于几种最先进的基于价值和基于 Transformer 的离线 RL 方法。

</details>

---



</details>

<details><summary><b>2026-03-05 (5 papers)</b></summary>

# arXiv World Model Papers - 2026-03-05

**Paper Count**: 5

---

## 1. Self-adapting Robotic Agents through Online Continual Reinforcement Learning with World Model Feedback / 通过世界模型反馈的在线持续强化学习自适应机器人代理

**Date**: 2026-03-04 | **arXiv**: [2603.04029v1](http://arxiv.org/abs/2603.04029v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.04029v1)

**Categories**: cs.RO, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

As learning-based robotic controllers are typically trained offline and deployed with fixed parameters, their ability to cope with unforeseen changes during operation is limited. Biologically inspired, this work presents a framework for online Continual Reinforcement Learning that enables automated adaptation during deployment. Building on DreamerV3, a model-based Reinforcement Learning algorithm, the proposed method leverages world model prediction residuals to detect out-of-distribution events and automatically trigger finetuning. Adaptation progress is monitored using both task-level performance signals and internal training metrics, allowing convergence to be assessed without external supervision and domain knowledge. The approach is validated on a variety of contemporary continuous control problems, including a quadruped robot in high-fidelity simulation, and a real-world model vehicle. Relevant metrics and their interpretation are presented and discussed, as well as resulting trade-offs described. The results sketch out how autonomous robotic agents could once move beyond static training regimes toward adaptive systems capable of self-reflection and -improvement during operation, just like their biological counterparts.

由于基于学习的机器人控制器通常是离线训练并使用固定参数进行部署的，因此它们应对操作过程中不可预见的变化的能力受到限制。受生物学启发，这项工作提出了一个在线持续强化学习框架，可以在部署过程中实现自动适应。该方法以基于模型的强化学习算法 DreamerV3 为基础，利用世界模型预测残差来检测分布外事件并自动触发微调。使用任务级绩效信号和内部培训指标来监控适应进度，从而无需外部监督和领域知识即可评估收敛性。该方法在各种当代连续控制问题上得到了验证，包括高保真模拟中的四足机器人和真实世界的模型车辆。介绍和讨论了相关指标及其解释，并描述了由此产生的权衡。结果概述了自主机器人代理如何超越静态训练制度，转向能够在操作过程中自我反思和改进的自适应系统，就像它们的生物对应物一样。

</details>

---

## 2. Specification-Driven Generation and Evaluation of Discrete-Event World Models via the DEVS Formalism / 通过 DEVS 形式规范驱动的离散事件世界模型的生成和评估

**Date**: 2026-03-04 | **arXiv**: [2603.03784v1](http://arxiv.org/abs/2603.03784v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.03784v1)

**Categories**: cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

World models are essential for planning and evaluation in agentic systems, yet existing approaches lie at two extremes: hand-engineered simulators that offer consistency and reproducibility but are costly to adapt, and implicit neural models that are flexible but difficult to constrain, verify, and debug over long horizons. We seek a principled middle ground that combines the reliability of explicit simulators with the flexibility of learned models, allowing world models to be adapted during online execution. By targeting a broad class of environments whose dynamics are governed by the ordering, timing, and causality of discrete events, such as queueing and service operations, embodied task planning, and message-mediated multi-agent coordination, we advocate explicit, executable discrete-event world models synthesized directly from natural-language specifications. Our approach adopts the DEVS formalism and introduces a staged LLM-based generation pipeline that separates structural inference of component interactions from component-level event and timing logic. To evaluate generated models without a unique ground truth, simulators emit structured event traces that are validated against specification-derived temporal and semantic constraints, enabling reproducible verification and localized diagnostics. Together, these contributions produce world models that are consistent over long-horizon rollouts, verifiable from observable behavior, and efficient to synthesize on demand during online execution.

世界模型对于代理系统的规划和评估至关重要，但现有的方法处于两个极端：手工设计的模拟器提供一致性和可重复性，但适应成本高昂；隐式神经模型虽然灵活，但难以长期约束、验证和调试。我们寻求一个有原则的中间立场，将显式模拟器的可靠性与学习模型的灵活性结合起来，允许在在线执行过程中调整世界模型。通过针对一系列其动态由离散事件的顺序、时间和因果关系控制的环境，例如排队和服务操作、具体任务规划和消息介导的多代理协调，我们提倡直接从自然语言规范合成的明确的、可执行的离散事件世界模型。我们的方法采用 DEVS 形式并引入了基于 LLM 的分阶段生成管道，该管道将组件交互的结构推理与组件级事件和时序逻辑分开。为了在没有唯一基本事实的情况下评估生成的模型，模拟器会发出结构化事件跟踪，这些跟踪根据规范派生的时间和语义约束进行验证，从而实现可重复的验证和本地化诊断。这些贡献共同产生了世界模型，这些模型在长期部署中是一致的，可以通过可观察的行为进行验证，并且可以在在线执行期间有效地按需合成。

</details>

---

## 3. Phys4D: Fine-Grained Physics-Consistent 4D Modeling from Video Diffusion / Phys4D：基于视频扩散的细粒度物理一致 4D 建模

**Date**: 2026-03-03 | **arXiv**: [2603.03485v1](http://arxiv.org/abs/2603.03485v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.03485v1)

**Categories**: cs.CV, cs.AI, cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Recent video diffusion models have achieved impressive capabilities as large-scale generative world models. However, these models often struggle with fine-grained physical consistency, exhibiting physically implausible dynamics over time. In this work, we present \textbf{Phys4D}, a pipeline for learning physics-consistent 4D world representations from video diffusion models. Phys4D adopts \textbf{a three-stage training paradigm} that progressively lifts appearance-driven video diffusion models into physics-consistent 4D world representations. We first bootstrap robust geometry and motion representations through large-scale pseudo-supervised pretraining, establishing a foundation for 4D scene modeling. We then perform physics-grounded supervised fine-tuning using simulation-generated data, enforcing temporally consistent 4D dynamics. Finally, we apply simulation-grounded reinforcement learning to correct residual physical violations that are difficult to capture through explicit supervision. To evaluate fine-grained physical consistency beyond appearance-based metrics, we introduce a set of \textbf{4D world consistency evaluation} that probe geometric coherence, motion stability, and long-horizon physical plausibility. Experimental results demonstrate that Phys4D substantially improves fine-grained spatiotemporal and physical consistency compared to appearance-driven baselines, while maintaining strong generative performance. Our project page is available at https://sensational-brioche-7657e7.netlify.app/

最近的视频扩散模型作为大规模生成世界模型已经取得了令人印象深刻的能力。然而，这些模型常常难以实现细粒度的物理一致性，随着时间的推移表现出物理上令人难以置信的动态。在这项工作中，我们提出了 \textbf{Phys4D}，一个用于从视频扩散模型学习物理一致的 4D 世界表示的管道。 Phys4D 采用 \textbf{三阶段训练范例}，逐步将外观驱动的视频扩散模型提升为物理一致的 4D 世界表示。我们首先通过大规模伪监督预训练引导鲁棒的几何和运动表示，为 4D 场景建模奠定基础。然后，我们使用模拟生成的数据执行基于物理的监督微调，从而实现时间一致的 4D 动态。最后，我们应用基于模拟的强化学习来纠正难以通过显式监督捕获的残留物理违规行为。为了评估基于外观的指标之外的细粒度物理一致性，我们引入了一组 \textbf{4D 世界一致性评估}，用于探测几何相干性、运动稳定性和长期物理合理性。实验结果表明，与外观驱动的基线相比，Phys4D 显着提高了细粒度时空和物理一致性，同时保持了强大的生成性能。我们的项目页面位于 https://sensational-brioche-7657e7.netlify.app/

</details>

---

## 4. Beyond Pixel Histories: World Models with Persistent 3D State / 超越像素历史：具有持久 3D 状态的世界模型

**Date**: 2026-03-03 | **arXiv**: [2603.03482v1](http://arxiv.org/abs/2603.03482v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.03482v1)

**Categories**: cs.CV, cs.AI, cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Interactive world models continually generate video by responding to a user's actions, enabling open-ended generation capabilities. However, existing models typically lack a 3D representation of the environment, meaning 3D consistency must be implicitly learned from data, and spatial memory is restricted to limited temporal context windows. This results in an unrealistic user experience and presents significant obstacles to down-stream tasks such as training agents. To address this, we present PERSIST, a new paradigm of world model which simulates the evolution of a latent 3D scene: environment, camera, and renderer. This allows us to synthesize new frames with persistent spatial memory and consistent geometry. Both quantitative metrics and a qualitative user study show substantial improvements in spatial memory, 3D consistency, and long-horizon stability over existing methods, enabling coherent, evolving 3D worlds. We further demonstrate novel capabilities, including synthesising diverse 3D environments from a single image, as well as enabling fine-grained, geometry-aware control over generated experiences by supporting environment editing and specification directly in 3D space. Project page: https://francelico.github.io/persist.github.io

交互式世界模型通过响应用户的操作来不断生成视频，从而实现开放式生成功能。然而，现有模型通常缺乏环境的 3D 表示，这意味着必须从数据中隐式学习 3D 一致性，并且空间记忆仅限于有限的时间上下文窗口。这会导致不切实际的用户体验，并对训练代理等下游任务造成重大障碍。为了解决这个问题，我们提出了 PERSIST，一种新的世界模型范式，它模拟潜在 3D 场景的演变：环境、相机和渲染器。这使我们能够合成具有持久空间记忆和一致几何形状的新框架。定量指标和定性用户研究都表明，与现有方法相比，空间记忆、3D 一致性和长期稳定性方面有了显着改进，从而实现连贯、不断发展的 3D 世界。我们进一步展示了新颖的功能，包括从单个图像合成不同的 3D 环境，以及通过直接在 3D 空间中支持环境编辑和规范来实现对生成的体验进行细粒度、几何感知的控制。项目页面：https://francelico.github.io/persist.github.io

</details>

---

## 5. Chain of World: World Model Thinking in Latent Motion / 世界之链：潜在运动中的世界模型思维

**Date**: 2026-03-03 | **arXiv**: [2603.03195v1](http://arxiv.org/abs/2603.03195v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.03195v1)

**Categories**: cs.CV, cs.AI, cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Vision-Language-Action (VLA) models are a promising path toward embodied intelligence, yet they often overlook the predictive and temporal-causal structure underlying visual dynamics. World-model VLAs address this by predicting future frames, but waste capacity reconstructing redundant backgrounds. Latent-action VLAs encode frame-to-frame transitions compactly, but lack temporally continuous dynamic modeling and world knowledge. To overcome these limitations, we introduce CoWVLA (Chain-of-World VLA), a new "Chain of World" paradigm that unifies world-model temporal reasoning with a disentangled latent motion representation. First, a pretrained video VAE serves as a latent motion extractor, explicitly factorizing video segments into structure and motion latents. Then, during pre-training, the VLA learns from an instruction and an initial frame to infer a continuous latent motion chain and predict the segment's terminal frame. Finally, during co-fine-tuning, this latent dynamic is aligned with discrete action prediction by jointly modeling sparse keyframes and action sequences in a unified autoregressive decoder. This design preserves the world-model benefits of temporal reasoning and world knowledge while retaining the compactness and interpretability of latent actions, enabling efficient visuomotor learning. Extensive experiments on robotic simulation benchmarks show that CoWVLA outperforms existing world-model and latent-action approaches and achieves moderate computational efficiency, highlighting its potential as a more effective VLA pretraining paradigm. The project website can be found at https://fx-hit.github.io/cowvla-io.

视觉-语言-动作（VLA）模型是实现具身智能的一条有希望的道路，但它们经常忽视视觉动态背后的预测和时间因果结构。世界模型 VLA 通过预测未来帧来​​解决这个问题，但会浪费容量来重建冗余背景。潜在动作 VLA 紧凑地编码帧到帧的转换，但缺乏时间连续的动态建模和世界知识。为了克服这些限制，我们引入了 CoWVLA（世界链 VLA），这是一种新的“世界链”范式，它将世界模型时间推理与解开的潜在运动表示相结合。首先，预训练的视频 VAE 用作潜在运动提取器，将视频片段显式分解为结构和潜在运动。然后，在预训练期间，VLA 从指令和初始帧中学习，以推断连续的潜在运动链并预测片段的终止帧。最后，在协同微调期间，通过在统一的自回归解码器中联合建模稀疏关键帧和动作序列，将这种潜在动态与离散动作预测对齐。这种设计保留了时间推理和世界知识的世界模型优势，同时保留了潜在动作的紧凑性和可解释性，从而实现了高效的视觉运动学习。对机器人模拟基准的大量实验表明，CoWVLA 优于现有的世界模型和潜在动作方法，并实现了适度的计算效率，凸显了其作为更有效的 VLA 预训练范例的潜力。该项目网站可以在 https://fx-hit.github.io/cowvla-io 找到。

</details>

---



</details>

<details><summary><b>2026-03-04 (5 papers)</b></summary>

# arXiv World Model Papers - 2026-03-04

**Paper Count**: 5

---

## 1. Contextual Latent World Models for Offline Meta Reinforcement Learning / 离线元强化学习的上下文潜在世界模型

**Date**: 2026-03-03 | **arXiv**: [2603.02935v1](http://arxiv.org/abs/2603.02935v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.02935v1)

**Categories**: cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Offline meta-reinforcement learning seeks to learn policies that generalize across related tasks from fixed datasets. Context-based methods infer a task representation from transition histories, but learning effective task representations without supervision remains a challenge. In parallel, latent world models have demonstrated strong self-supervised representation learning through temporal consistency. We introduce contextual latent world models, which condition latent world models on inferred task representations and train them jointly with the context encoder. This enforces task-conditioned temporal consistency, yielding task representations that capture task-dependent dynamics rather than merely discriminating between tasks. Our method learns more expressive task representations and significantly improves generalization to unseen tasks across MuJoCo, Contextual-DeepMind Control, and Meta-World benchmarks.

离线元强化学习旨在学习从固定数据集中泛化相关任务的策略。基于上下文的方法从转换历史中推断任务表示，但在没有监督的情况下学习有效的任务表示仍然是一个挑战。与此同时，潜在世界模型通过时间一致性展示了强大的自我监督表示学习。我们引入了上下文潜在世界模型，它根据推断的任务表示来调节潜在世界模型，并与上下文编码器联合训练它们。这增强了任务条件的时间一致性，产生捕获任务相关动态的任务表示，而不仅仅是区分任务。我们的方法学习更具表现力的任务表示，并显着提高了对 MuJoCo、Contextual-DeepMind Control 和 Meta-World 基准中未见过的任务的泛化。

</details>

---

## 2. Next Embedding Prediction Makes World Models Stronger / 下一个嵌入预测使世界模型变得更强

**Date**: 2026-03-03 | **arXiv**: [2603.02765v1](http://arxiv.org/abs/2603.02765v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.02765v1)

**Categories**: cs.LG, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Capturing temporal dependencies is critical for model-based reinforcement learning (MBRL) in partially observable, high-dimensional domains. We introduce NE-Dreamer, a decoder-free MBRL agent that leverages a temporal transformer to predict next-step encoder embeddings from latent state sequences, directly optimizing temporal predictive alignment in representation space. This approach enables NE-Dreamer to learn coherent, predictive state representations without reconstruction losses or auxiliary supervision. On the DeepMind Control Suite, NE-Dreamer matches or exceeds the performance of DreamerV3 and leading decoder-free agents. On a challenging subset of DMLab tasks involving memory and spatial reasoning, NE-Dreamer achieves substantial gains. These results establish next-embedding prediction with temporal transformers as an effective, scalable framework for MBRL in complex, partially observable environments.

捕获时间依赖性对于部分可观察的高维领域中基于模型的强化学习 (MBRL) 至关重要。我们引入了 NE-Dreamer，一种无解码器的 MBRL 代理，它利用时间变换器从潜在状态序列预测下一步编码器嵌入，直接优化表示空间中的时间预测对齐。这种方法使 NE-Dreamer 能够学习连贯的、预测性的状态表示，而无需重建损失或辅助监督。在 DeepMind Control Suite 上，NE-Dreamer 的性能达到或超过了 DreamerV3 和领先的无解码器代理。在涉及记忆和空间推理的 DMLab 任务的挑战性子集上，NE-Dreamer 取得了显着的成果。这些结果利用时间变换器建立了下一次嵌入预测，作为复杂、部分可观察环境中 MBRL 的有效、可扩展框架。

</details>

---

## 3. What Capable Agents Must Know: Selection Theorems for Robust Decision-Making under Uncertainty / 有能力的智能体必须了解什么：不确定性下稳健决策的选择定理

**Date**: 2026-03-03 | **arXiv**: [2603.02491v1](http://arxiv.org/abs/2603.02491v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.02491v1)

**Categories**: cs.LG, cs.AI, cs.RO, q-bio.NC, stat.ML

<details><summary><b>Abstract / 摘要</b></summary>

As artificial agents become increasingly capable, what internal structure is *necessary* for an agent to act competently under uncertainty? Classical results show that optimal control can be *implemented* using belief states or world models, but not that such representations are required. We prove quantitative "selection theorems" showing that low *average-case regret* on structured families of action-conditioned prediction tasks forces an agent to implement a predictive, structured internal state. Our results cover stochastic policies, partial observability, and evaluation under task distributions, without assuming optimality, determinism, or access to an explicit model. Technically, we reduce predictive modeling to binary "betting" decisions and show that regret bounds limit probability mass on suboptimal bets, enforcing the predictive distinctions needed to separate high-margin outcomes. In fully observed settings, this yields approximate recovery of the interventional transition kernel; under partial observability, it implies necessity of belief-like memory and predictive state, addressing an open question in prior world-model recovery work.

随着人工智能主体的能力越来越强，什么样的内部结构对于一个主体在不确定性下能够胜任行动是“必要的”？经典结果表明，可以使用信念状态或世界模型“实现”最优控制，但并不需要这种表示。我们证明了定量的“选择定理”，表明对动作条件预测任务的结构化系列的低“平均情况遗憾”迫使代理实施预测性的、结构化的内部状态。我们的结果涵盖了随机策略、部分可观察性和任务分布下的评估，而不假设最优性、确定性或访问显式模型。从技术上讲，我们将预测模型简化为二元“投注”决策，并表明遗憾界限限制了次优投注的概率质量，从而强化了分离高利润结果所需的预测区别。在完全观察的设置中，这会产生介入过渡内核的近似恢复；在部分可观察性下，它意味着类似信念的记忆和预测状态的必要性，解决了先前世界模型恢复工作中的一个悬而未决的问题。

</details>

---

## 4. Discrete World Models via Regularization / 通过正则化的离散世界模型

**Date**: 2026-03-02 | **arXiv**: [2603.01748v1](http://arxiv.org/abs/2603.01748v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.01748v1)

**Categories**: cs.LG, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

World models aim to capture the states and dynamics of an environment in a compact latent space. Moreover, using Boolean state representations is particularly useful for search heuristics and symbolic reasoning and planning. Existing approaches keep latents informative via decoder-based reconstruction, or instead via contrastive or reward signals. In this work, we introduce Discrete World Models via Regularization (DWMR): a reconstruction-free and contrastive-free method for unsupervised Boolean world-model learning. In particular, we introduce a novel world-modeling loss that couples latent prediction with specialized regularizers. Such regularizers maximize the entropy and independence of the representation bits through variance, correlation, and coskewness penalties, while simultaneously enforcing a locality prior for sparse action changes. To enable effective optimization, we also introduce a novel training scheme improving robustness to discrete roll-outs. Experiments on two benchmarks with underlying combinatorial structure show that DWMR learns more accurate representations and transitions than reconstruction-based alternatives. Finally, DWMR can also be paired with an auxiliary reconstruction decoder, and this combination yields additional gains.

世界模型旨在捕捉紧凑潜在空间中环境的状态和动态。此外，使用布尔状态表示对于搜索启发式以及符号推理和规划特别有用。现有的方法通过基于解码器的重建，或者通过对比或奖励信号来保持潜在信息。在这项工作中，我们介绍了通过正则化的离散世界模型（DWMR）：一种用于无监督布尔世界模型学习的无重建和无对比方法。特别是，我们引入了一种新颖的世界建模损失，它将潜在预测与专门的正则化器结合起来。这种正则化器通过方差、相关性和余偏度惩罚来最大化表示位的熵和独立性，同时对稀疏动作变化强制执行局部性先验。为了实现有效的优化，我们还引入了一种新颖的训练方案，提高了离散推出的鲁棒性。对具有底层组合结构的两个基准进行的实验表明，DWMR 比基于重建的替代方案能够学习更准确的表示和转换。最后，DWMR 还可以与辅助重建解码器配对，这种组合会产生额外的增益。

</details>

---

## 5. Scaling Tasks, Not Samples: Mastering Humanoid Control through Multi-Task Model-Based Reinforcement Learning / 扩展任务而不是样本：通过基于多任务模型的强化学习掌握人形控制

**Date**: 2026-03-02 | **arXiv**: [2603.01452v1](http://arxiv.org/abs/2603.01452v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.01452v1)

**Categories**: cs.AI, cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Developing generalist robots capable of mastering diverse skills remains a central challenge in embodied AI. While recent progress emphasizes scaling model parameters and offline datasets, such approaches are limited in robotics, where learning requires active interaction. We argue that effective online learning should scale the \emph{number of tasks}, rather than the number of samples per task. This regime reveals a structural advantage of model-based reinforcement learning (MBRL). Because physical dynamics are invariant across tasks, a shared world model can aggregate multi-task experience to learn robust, task-agnostic representations. In contrast, model-free methods suffer from gradient interference when tasks demand conflicting actions in similar states. Task diversity therefore acts as a regularizer for MBRL, improving dynamics learning and sample efficiency. We instantiate this idea with \textbf{EfficientZero-Multitask (EZ-M)}, a sample-efficient multi-task MBRL algorithm for online learning. Evaluated on \textbf{HumanoidBench}, a challenging whole-body control benchmark, EZ-M achieves state-of-the-art performance with significantly higher sample efficiency than strong baselines, without extreme parameter scaling. These results establish task scaling as a critical axis for scalable robotic learning. The project website is available \href{https://yewr.github.io/ez_m/}{here}.

开发能够掌握多种技能的多面手机器人仍然是实体人工智能的核心挑战。虽然最近的进展强调缩放模型参数和离线数据集，但这种方法在机器人技术中受到限制，因为机器人技术的学习需要主动交互。我们认为有效的在线学习应该扩展\emph{任务数量}，而不是每个任务的样本数量。这种机制揭示了基于模型的强化学习（MBRL）的结构优势。由于物理动力学在不同任务之间是不变的，因此共享世界模型可以聚合多任务经验来学习稳健的、与任务无关的表示。相比之下，当任务需要在相似状态下采取冲突的行动时，无模型方法会受到梯度干扰。因此，任务多样性可以作为 MBRL 的正则化器，提高动态学习和样本效率。我们用 \textbf{EfficientZero-Multitask (EZ-M)} 来实例化这个想法，这是一种用于在线学习的样本高效多任务 MBRL 算法。在具有挑战性的全身控制基准 \textbf{HumanoidBench} 上进行评估，EZ-M 实现了最先进的性能，其样本效率显着高于强基线，且没有极端的参数缩放。这些结果将任务扩展确立为可扩展机器人学习的关键轴。该项目网站位于\href{https://yewr.github.io/ez_m/}{此处}。

</details>

---



</details>

<details><summary><b>2026-03-03 (1 papers)</b></summary>

# arXiv World Model Papers - 2026-03-03

**Paper Count**: 1

---

## 1. MetaMind: General and Cognitive World Models in Multi-Agent Systems by Meta-Theory of Mind / MetaMind：多智能体系统中的通用认知世界模型

**Date**: 2026-02-28 | **arXiv**: [2603.00808v1](http://arxiv.org/abs/2603.00808v1) | **PDF**: [Link](http://arxiv.org/pdf/2603.00808v1)

**Categories**: cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

A major challenge for world models in multi-agent systems is to understand interdependent agent dynamics, predict interactive multi-agent trajectories, and plan over long horizons with collective awareness, without centralized supervision or explicit communication. In this paper, MetaMind, a general and cognitive world model for multi-agent systems that leverages a novel meta-theory of mind (Meta-ToM) framework, is proposed. Through MetaMind, each agent learns not only to predict and plan over its own beliefs, but also to inversely reason goals and beliefs from its own behavior trajectories. This self-reflective, bidirectional inference loop enables each agent to learn a metacognitive ability in a self-supervised manner. Then, MetaMind is shown to generalize the metacognitive ability from first-person to third-person through analogical reasoning. Thus, in multi-agent systems, each agent with MetaMind can actively reason about goals and beliefs of other agents from limited, observable behavior trajectories in a zero-shot manner, and then adapt to emergent collective intention without an explicit communication mechanism. Extended simulation results on diverse multi-agent tasks demonstrate that MetaMind can achieve superior task performance and outperform baselines in few-shot multi-agent generalization.

多智能体系统中世界模型的一个主要挑战是理解相互依赖的智能体动态、预测交互式多智能体轨迹，并在没有集中监督或明确沟通的情况下以集体意识进行长期规划。在本文中，提出了 MetaMind，这是一种利用新颖的元心理理论 (Meta-ToM) 框架的多智能体系统的通用认知世界模型。通过 MetaMind，每个智能体不仅学会预测和规划自己的信念，还能根据自己的行为轨迹反向推理目标和信念。这种自我反思的双向推理循环使每个智能体能够以自我监督的方式学习元认知能力。然后，MetaMind 通过类比推理将元认知能力从第一人称推广到第三人称。因此，在多智能体系统中，每个具有 MetaMind 的智能体都可以从有限的、可观察的行为轨迹中以零样本的方式主动推理其他智能体的目标和信念，然后在没有明确的通信机制的情况下适应新出现的集体意图。对各种多智能体任务的扩展模拟结果表明，MetaMind 可以实现卓越的任务性能，并在少样本多智能体泛化中超越基线。

</details>

---



</details>

<details><summary><b>2026-03-02 (2 papers)</b></summary>

# arXiv World Model Papers - 2026-03-02

**Paper Count**: 2

---

## 1. Planning from Observation and Interaction / 从观察和互动中进行规划

**Date**: 2026-02-27 | **arXiv**: [2602.24121v1](http://arxiv.org/abs/2602.24121v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.24121v1)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Observational learning requires an agent to learn to perform a task by referencing only observations of the performed task. This work investigates the equivalent setting in real-world robot learning where access to hand-designed rewards and demonstrator actions are not assumed. To address this data-constrained setting, this work presents a planning-based Inverse Reinforcement Learning (IRL) algorithm for world modeling from observation and interaction alone. Experiments conducted entirely in the real-world demonstrate that this paradigm is effective for learning image-based manipulation tasks from scratch in under an hour, without assuming prior knowledge, pre-training, or data of any kind beyond task observations. Moreover, this work demonstrates that the learned world model representation is capable of online transfer learning in the real-world from scratch. In comparison to existing approaches, including IRL, RL, and Behavior Cloning (BC), which have more restrictive assumptions, the proposed approach demonstrates significantly greater sample efficiency and success rates, enabling a practical path forward for online world modeling and planning from observation and interaction. Videos and more at: https://uwrobotlearning.github.io/mpail2/.

观察学习要求代理仅通过参考对所执行任务的观察来学习执行任务。这项工作研究了现实世界机器人学习中的等效设置，其中不假设可以获得手工设计的奖励和演示动作。为了解决这种数据受限的环境，这项工作提出了一种基于规划的逆强化学习（IRL）算法，用于仅通过观察和交互进行世界建模。完全在现实世界中进行的实验表明，这种范例对于在一小时内从头开始学习基于图像的操作任务是有效的，无需假设先验知识、预训练或任务观察之外的任何类型的数据。此外，这项工作表明，学习到的世界模型表示能够从头开始在现实世界中进行在线迁移学习。与具有更多限制性假设的现有方法（包括 IRL、RL 和行为克隆 (BC)）相比，所提出的方法表现出显着更高的样本效率和成功率，为通过观察和交互进行在线世界建模和规划提供了一条实用的道路。视频及更多内容请访问：https://uwrobotlearning.github.io/mpail2/。

</details>

---

## 2. Foundation World Models for Agents that Learn, Verify, and Adapt Reliably Beyond Static Environments / 代理的基础世界模型可以在静态环境之外可靠地学习、验证和适应

**Date**: 2026-02-27 | **arXiv**: [2602.23997v1](http://arxiv.org/abs/2602.23997v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.23997v1)

**Categories**: cs.LG, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

The next generation of autonomous agents must not only learn efficiently but also act reliably and adapt their behavior in open worlds. Standard approaches typically assume fixed tasks and environments with little or no novelty, which limits world models' ability to support agents that must evolve their policies as conditions change. This paper outlines a vision for foundation world models: persistent, compositional representations that unify reinforcement learning, reactive/program synthesis, and abstraction mechanisms. We propose an agenda built around four components: (i) learnable reward models from specifications to support optimization with clear objectives; (ii) adaptive formal verification integrated throughout learning; (iii) online abstraction calibration to quantify the reliability of the model's predictions; and (iv) test-time synthesis and world-model generation guided by verifiers. Together, these components enable agents to synthesize verifiable programs, derive new policies from a small number of interactions, and maintain correctness while adapting to novelty. The resulting framework positions foundation world models as a substrate for learning, reasoning, and adaptation, laying the groundwork for agents that not only act well but can explain and justify the behavior they adopt.

下一代自主智能体不仅必须高效学习，而且必须可靠地行动并在开放世界中调整自己的行为。标准方法通常假设固定的任务和环境，很少或没有新颖性，这限制了世界模型支持代理的能力，代理必须随着条件的变化而发展其策略。本文概述了基础世界模型的愿景：统一强化学习、反应/程序合成和抽象机制的持久组合表示。我们提出了一个围绕四个组成部分构建的议程：（i）来自规范的可学习奖励模型，以支持具有明确目标的优化； (ii) 将自适应形式验证融入整个学习过程； (iii) 在线抽象校准，以量化模型预测的可靠性； (iv) 由验证者指导的测试时综合和世界模型生成。这些组件共同使代理能够综合可验证的程序，从少量的交互中得出新的策略，并在适应新颖性的同时保持正确性。由此产生的框架将基础世界模型定位为学习、推理和适应的基础，为智能体奠定了基础，这些智能体不仅表现良好，而且可以解释和证明他们所采取的行为。

</details>

---



</details>

<details><summary><b>2026-02-27 (7 papers)</b></summary>

# arXiv World Model Papers - 2026-02-27

**Paper Count**: 7

---

## 1. Risk-Aware World Model Predictive Control for Generalizable End-to-End Autonomous Driving / 用于通用端到端自动驾驶的风险感知世界模型预测控制

**Date**: 2026-02-26 | **arXiv**: [2602.23259v1](http://arxiv.org/abs/2602.23259v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.23259v1)

**Categories**: cs.CV, cs.AI, cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

With advances in imitation learning (IL) and large-scale driving datasets, end-to-end autonomous driving (E2E-AD) has made great progress recently. Currently, IL-based methods have become a mainstream paradigm: models rely on standard driving behaviors given by experts, and learn to minimize the discrepancy between their actions and expert actions. However, this objective of "only driving like the expert" suffers from limited generalization: when encountering rare or unseen long-tail scenarios outside the distribution of expert demonstrations, models tend to produce unsafe decisions in the absence of prior experience. This raises a fundamental question: Can an E2E-AD system make reliable decisions without any expert action supervision? Motivated by this, we propose a unified framework named Risk-aware World Model Predictive Control (RaWMPC) to address this generalization dilemma through robust control, without reliance on expert demonstrations. Practically, RaWMPC leverages a world model to predict the consequences of multiple candidate actions and selects low-risk actions through explicit risk evaluation. To endow the world model with the ability to predict the outcomes of risky driving behaviors, we design a risk-aware interaction strategy that systematically exposes the world model to hazardous behaviors, making catastrophic outcomes predictable and thus avoidable. Furthermore, to generate low-risk candidate actions at test time, we introduce a self-evaluation distillation method to distill riskavoidance capabilities from the well-trained world model into a generative action proposal network without any expert demonstration. Extensive experiments show that RaWMPC outperforms state-of-the-art methods in both in-distribution and out-of-distribution scenarios, while providing superior decision interpretability.

随着模仿学习（IL）和大规模驾驶数据集的进步，端到端自动驾驶（E2E-AD）最近取得了巨大进展。目前，基于IL的方法已成为主流范式：模型依赖于专家给出的标准驾驶行为，并学习最小化其行为与专家行为之间的差异。然而，“只像专家一样驾驶”这一目标的泛化能力有限：当遇到专家演示分布之外的罕见或未见的长尾场景时，模型往往会在缺乏先验经验的情况下做出不安全的决策。这就提出了一个基本问题：E2E-AD 系统能否在没有任何专家行动监督的情况下做出可靠的决策？受此启发，我们提出了一个名为风险感知世界模型预测控制（RaWMPC）的统一框架，通过稳健控制来解决这种泛化困境，而不依赖于专家演示。实际上，RaWMPC 利用世界模型来预测多个候选行动的后果，并通过明确的风险评估选择低风险行动。为了赋予世界模型预测危险驾驶行为结果的能力，我们设计了一种风险感知交互策略，系统地将世界模型暴露于危险行为，使灾难性结果可预测，从而可以避免。此外，为了在测试时生成低风险的候选动作，我们引入了一种自我评估蒸馏方法，将风险规避能力从训练有素的世界模型中提取到生成动作提案网络中，而无需任何专家演示。大量实验表明，RaWMPC 在分布内和分布外场景中均优于最先进的方法，同时提供卓越的决策可解释性。

</details>

---

## 2. MetaOthello: A Controlled Study of Multiple World Models in Transformers / MetaOthello：变形金刚中多个世界模型的对照研究

**Date**: 2026-02-26 | **arXiv**: [2602.23164v1](http://arxiv.org/abs/2602.23164v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.23164v1)

**Categories**: cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Foundation models must handle multiple generative processes, yet mechanistic interpretability largely studies capabilities in isolation; it remains unclear how a single transformer organizes multiple, potentially conflicting "world models". Previous experiments on Othello playing neural-networks test world-model learning but focus on a single game with a single set of rules. We introduce MetaOthello, a controlled suite of Othello variants with shared syntax but different rules or tokenizations, and train small GPTs on mixed-variant data to study how multiple world models are organized in a shared representation space. We find that transformers trained on mixed-game data do not partition their capacity into isolated sub-models; instead, they converge on a mostly shared board-state representation that transfers causally across variants. Linear probes trained on one variant can intervene on another's internal state with effectiveness approaching that of matched probes. For isomorphic games with token remapping, representations are equivalent up to a single orthogonal rotation that generalizes across layers. When rules partially overlap, early layers maintain game-agnostic representations while a middle layer identifies game identity, and later layers specialize. MetaOthello offers a path toward understanding not just whether transformers learn world models, but how they organize many at once.

基础模型必须处理多个生成过程，但机械可解释性主要研究孤立的能力；目前尚不清楚单个变压器如何组织多个可能相互冲突的“世界模型”。之前关于黑白棋玩神经网络的实验测试了世界模型学习，但重点关注具有一组规则的单个游戏。我们引入了 MetaOthello，这是一套受控的 Othello 变体套件，具有共享语法但不同的规则或标记化，并在混合变体数据上训练小型 GPT，以研究如何在共享表示空间中组织多个世界模型。我们发现，在混合游戏数据上训练的 Transformer 不会将其容量划分为孤立的子模型；相反，它们集中在一个大部分共享的董事会状态表示上，该表示在变体之间因果转移。在一种变体上训练的线性探针可以干预另一种变体的内部状态，其有效性接近匹配探针。对于具有令牌重新映射的同构游戏，表示相当于跨层泛化的单个正交旋转。当规则部分重叠时，早期层保持与游戏无关的表示，而中间层识别游戏身份，而后面的层则专门化。 MetaOthello 不仅提供了一条了解变形金刚是否学习世界模型的途径，还提供了一条了解它们如何同时组织多个世界模型的途径。

</details>

---

## 3. The Trinity of Consistency as a Defining Principle for General World Models / 一致性的三位一体作为一般世界模型的定义原则

**Date**: 2026-02-26 | **arXiv**: [2602.23152v1](http://arxiv.org/abs/2602.23152v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.23152v1)

**Categories**: cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

The construction of World Models capable of learning, simulating, and reasoning about objective physical laws constitutes a foundational challenge in the pursuit of Artificial General Intelligence. Recent advancements represented by video generation models like Sora have demonstrated the potential of data-driven scaling laws to approximate physical dynamics, while the emerging Unified Multimodal Model (UMM) offers a promising architectural paradigm for integrating perception, language, and reasoning. Despite these advances, the field still lacks a principled theoretical framework that defines the essential properties requisite for a General World Model. In this paper, we propose that a World Model must be grounded in the Trinity of Consistency: Modal Consistency as the semantic interface, Spatial Consistency as the geometric basis, and Temporal Consistency as the causal engine. Through this tripartite lens, we systematically review the evolution of multimodal learning, revealing a trajectory from loosely coupled specialized modules toward unified architectures that enable the synergistic emergence of internal world simulators. To complement this conceptual framework, we introduce CoW-Bench, a benchmark centered on multi-frame reasoning and generation scenarios. CoW-Bench evaluates both video generation models and UMMs under a unified evaluation protocol. Our work establishes a principled pathway toward general world models, clarifying both the limitations of current systems and the architectural requirements for future progress.

构建能够学习、模拟和推理客观物理定律的世界模型是追求通用人工智能的基本挑战。以 Sora 等视频生成模型为代表的最新进展证明了数据驱动的缩放定律在近似物理动力学方面的潜力，而新兴的统一多模态模型 (UMM) 则为集成感知、语言和推理提供了一种有前途的架构范例。尽管取得了这些进展，该领域仍然缺乏一个原则性的理论框架来定义通用世界模型所需的基本属性。在本文中，我们提出世界模型必须建立在一致性三位一体的基础上：模态一致性作为语义接口，空间一致性作为几何基础，时间一致性作为因果引擎。通过这个三方视角，我们系统地回顾了多模态学习的演变，揭示了从松散耦合的专业模块到统一架构的轨迹，从而实现内部世界模拟器的协同出现。为了补充这个概念框架，我们引入了 CoW-Bench，这是一个以多帧推理和生成场景为中心的基准测试。 CoW-Bench 在统一的评估协议下评估视频生成模型和 UMM。我们的工作建立了通向通用世界模型的原则性途径，阐明了当前系统的局限性和未来进步的架构要求。

</details>

---

## 4. On Sample-Efficient Generalized Planning via Learned Transition Models / 通过学习转移模型进行样本有效的广义规划

**Date**: 2026-02-26 | **arXiv**: [2602.23148v1](http://arxiv.org/abs/2602.23148v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.23148v1)

**Categories**: cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Generalized planning studies the construction of solution strategies that generalize across families of planning problems sharing a common domain model, formally defined by a transition function $γ: S \times A \rightarrow S$. Classical approaches achieve such generalization through symbolic abstractions and explicit reasoning over $γ$. In contrast, recent Transformer-based planners, such as PlanGPT and Plansformer, largely cast generalized planning as direct action-sequence prediction, bypassing explicit transition modeling. While effective on in-distribution instances, these approaches typically require large datasets and model sizes, and often suffer from state drift in long-horizon settings due to the absence of explicit world-state evolution. In this work, we formulate generalized planning as a transition-model learning problem, in which a neural model explicitly approximates the successor-state function $\hatγ \approx γ$ and generates plans by rolling out symbolic state trajectories. Instead of predicting actions directly, the model autoregressively predicts intermediate world states, thereby learning the domain dynamics as an implicit world model. To study size-invariant generalization and sample efficiency, we systematically evaluate multiple state representations and neural architectures, including relational graph encodings. Our results show that learning explicit transition models yields higher out-of-distribution satisficing-plan success than direct action-sequence prediction in multiple domains, while achieving these gains with significantly fewer training instances and smaller models. This is an extended version of a short paper accepted at ICAPS 2026 under the same title.

广义规划研究解决方案策略的构建，该解决方案策略泛化于共享公共域模型的规划问题系列，由转换函数 $γ 正式定义：S \times A \rightarrow S$。经典方法通过符号抽象和对 $γ$ 的显式推理来实现这种泛化。相比之下，最近基于 Transformer 的规划器（例如 PlanGPT 和 Plansformer）在很大程度上将广义规划视为直接动作序列预测，绕过了显式转换建模。虽然对分布内实例有效，但这些方法通常需要大型数据集和模型大小，并且由于缺乏明确的世界状态演化，常常会在长范围设置中遭受状态漂移。在这项工作中，我们将广义规划制定为转换模型学习问题，其中神经模型显式逼近后继状态函数 $\hatγ \approx γ$ 并通过推出符号状态轨迹来生成计划。该模型不是直接预测动作，而是自回归预测中间世界状态，从而将域动态学习为隐式世界模型。为了研究大小不变的泛化和样本效率，我们系统地评估了多种状态表示和神经架构，包括关系图编码。我们的结果表明，在多个领域中，学习显式转换模型比直接行动序列预测能产生更高的分布外满足计划成功率，同时通过显着更少的训练实例和更小的模型来实现这些收益。这是 ICAPS 2026 上接受的同名短论文的扩展版本。

</details>

---

## 5. GeoWorld: Geometric World Models / GeoWorld：几何世界模型

**Date**: 2026-02-26 | **arXiv**: [2602.23058v1](http://arxiv.org/abs/2602.23058v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.23058v1)

**Categories**: cs.CV, cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Energy-based predictive world models provide a powerful approach for multi-step visual planning by reasoning over latent energy landscapes rather than generating pixels. However, existing approaches face two major challenges: (i) their latent representations are typically learned in Euclidean space, neglecting the underlying geometric and hierarchical structure among states, and (ii) they struggle with long-horizon prediction, which leads to rapid degradation across extended rollouts. To address these challenges, we introduce GeoWorld, a geometric world model that preserves geometric structure and hierarchical relations through a Hyperbolic JEPA, which maps latent representations from Euclidean space onto hyperbolic manifolds. We further introduce Geometric Reinforcement Learning for energy-based optimization, enabling stable multi-step planning in hyperbolic latent space. Extensive experiments on CrossTask and COIN demonstrate around 3% SR improvement in 3-step planning and 2% SR improvement in 4-step planning compared to the state-of-the-art V-JEPA 2. Project website: https://steve-zeyu-zhang.github.io/GeoWorld.

基于能量的预测世界模型通过推理潜在的能量景观而不是生成像素，为多步骤视觉规划提供了一种强大的方法。然而，现有的方法面临两个主要挑战：（i）它们的潜在表示通常是在欧几里得空间中学习的，忽略了状态之间潜在的几何和层次结构；（ii）它们难以进行长期预测，这导致在扩展部署过程中快速退化。为了解决这些挑战，我们引入了 GeoWorld，这是一种几何世界模型，通过双曲 JEPA 保留几何结构和层次关系，它将欧几里得空间的潜在表示映射到双曲流形。我们进一步引入几何强化学习进行基于能量的优化，从而在双曲潜在空间中实现稳定的多步规划。 CrossTask 和 COIN 上的大量实验表明，与最先进的 V-JEPA 2 相比，3 步规划的 SR 提高了约 3%，4 步规划的 SR 提高了 2%。 项目网站：https://steve-zeyu-zhang.github.io/GeoWorld。

</details>

---

## 6. Imagination Helps Visual Reasoning, But Not Yet in Latent Space / 想象力有助于视觉推理，但尚未在潜在空间中发挥作用

**Date**: 2026-02-26 | **arXiv**: [2602.22766v1](http://arxiv.org/abs/2602.22766v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.22766v1)

**Categories**: cs.CL

<details><summary><b>Abstract / 摘要</b></summary>

Latent visual reasoning aims to mimic human's imagination process by meditating through hidden states of Multimodal Large Language Models. While recognized as a promising paradigm for visual reasoning, the underlying mechanisms driving its effectiveness remain unclear. Motivated to demystify the true source of its efficacy, we investigate the validity of latent reasoning using Causal Mediation Analysis. We model the process as a causal chain: the input as the treatment, the latent tokens as the mediator, and the final answer as the outcome. Our findings uncover two critical disconnections: (a) Input-Latent Disconnect: dramatic perturbations on the input result in negligible changes to the latent tokens, suggesting that latent tokens do not effectively attend to the input sequence. (b) Latent-Answer Disconnect: perturbations on the latent tokens yield minimal impact on the final answer, indicating the limited causal effect latent tokens imposing on the outcome. Furthermore, extensive probing analysis reveals that latent tokens encode limited visual information and exhibit high similarity. Consequently, we challenge the necessity of latent reasoning and propose a straightforward alternative named CapImagine, which teaches the model to explicitly imagine using text. Experiments on vision-centric benchmarks show that CapImagine significantly outperforms complex latent-space baselines, highlighting the superior potential of visual reasoning through explicit imagination.

潜在视觉推理旨在通过多模态大语言模型的隐藏状态进行冥想来模仿人类的想象力过程。虽然被认为是视觉推理的一种有前途的范例，但驱动其有效性的潜在机制仍不清楚。为了揭开其功效的真正来源的神秘面纱，我们使用因果中介分析研究了潜在推理的有效性。我们将过程建模为因果链：输入作为处理，潜在标记作为中介，最终答案作为结果。我们的发现揭示了两个关键的断开：（a）输入-潜在断开：输入的剧烈扰动导致潜在标记的变化可以忽略不计，这表明潜在标记不能有效地关注输入序列。 (b) 潜在答案断开：对潜在标记的扰动对最终答案产生的影响最小，表明潜在标记对结果的因果影响有限。此外，广泛的探测分析表明，潜在标记编码有限的视觉信息并表现出高度相似性。因此，我们挑战潜在推理的必要性，并提出了一个名为 CapImagine 的简单替代方案，它教会模型使用文本明确地想象。以视觉为中心的基准测试表明，CapImagine 的性能显着优于复杂的潜在空间基线，凸显了通过显式想象进行视觉推理的卓越潜力。

</details>

---

## 7. CWM: Contrastive World Models for Action Feasibility Learning in Embodied Agent Pipelines / CWM：具体代理管道中行动可行性学习的对比世界模型

**Date**: 2026-02-25 | **arXiv**: [2602.22452v1](http://arxiv.org/abs/2602.22452v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.22452v1)

**Categories**: cs.AI, cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

A reliable action feasibility scorer is a critical bottleneck in embodied agent pipelines: before any planning or reasoning occurs, the agent must identify which candidate actions are physically executable in the current state. Existing approaches use supervised fine-tuning (SFT) to train action scorers, but SFT treats each candidate independently and does not explicitly teach the model to discriminate between actions that are physically correct and those that are subtly wrong. We propose the Contrastive World Model (CWM), which fine-tunes a large language model (LLM) as an action scorer using an InfoNCE contrastive objective with hard-mined negative examples. The key idea is to push valid actions away from invalid ones in scoring space, with special emphasis on hard negatives: semantically similar but physically incompatible candidates. We evaluate CWM on the ScienceWorld benchmark through two studies. First, an intrinsic affordance evaluation on 605 hard-negative test pairs shows that CWM outperforms SFT by +6.76 percentage points on Precision@1 for minimal-edit negatives -- cases where a single word changes the physical outcome -- and achieves a higher AUC-ROC (0.929 vs. 0.906). Second, a live filter characterisation study measures how well CWM ranks gold-path actions against all valid environment actions during task execution. Under out-of-distribution stress conditions, CWM maintains a significantly better safety margin (-2.39) than SFT (-3.96), indicating that the gold action is ranked closer to the top. These results support the hypothesis that contrastive training induces representations that capture physical feasibility more faithfully than SFT alone.

可靠的行动可行性评分器是具体代理管道中的关键瓶颈：在进行任何计划或推理之前，代理必须确定哪些候选行动在当前状态下可以物理执行。现有方法使用监督微调（SFT）来训练动作评分器，但 SFT 独立对待每个候选者，并且没有明确教导模型区分物理上正确的动作和细微错误的动作。我们提出了对比世界模型（CWM），它使用 InfoNCE 对比目标和精心挖掘的负面例子来微调大型语言模型（LLM）作为动作评分器。关键思想是在评分空间中将有效动作从无效动作中剔除，特别强调硬否定：语义上相似但物理上不兼容的候选者。我们通过两项研究在 ScienceWorld 基准上评估 CWM。首先，对 605 个硬阴性测试对进行的内在可供性评估表明，对于最小编辑阴性（单个单词改变物理结果的情况），CWM 在 Precision@1 上的表现优于 SFT +6.76 个百分点，并实现了更高的 AUC-ROC（0.929 比 0.906）。其次，实时过滤器特征研究衡量 CWM 在任务执行期间根据所有有效环境操作对黄金路径操作进行排名的情况。在分布外压力条件下，CWM 保持了明显优于 SFT（-3.96）的安全裕度（-2.39），表明黄金行动排名更接近顶部。这些结果支持这样的假设：对比训练比单独的 SFT 更能忠实地捕捉物理可行性。

</details>

---



</details>

<details><summary><b>2026-02-26 (3 papers)</b></summary>

# arXiv World Model Papers - 2026-02-26

**Paper Count**: 3

---

## 1. Self-Correcting VLA: Online Action Refinement via Sparse World Imagination / 自我修正VLA：通过稀疏世界想象力改进在线动作

**Date**: 2026-02-25 | **arXiv**: [2602.21633v1](http://arxiv.org/abs/2602.21633v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21633v1)

**Categories**: cs.RO, cs.AI, cs.CV

**Code**: https://github.com/Kisaragi0/SC-VLA.

<details><summary><b>Abstract / 摘要</b></summary>

Standard vision-language-action (VLA) models rely on fitting statistical data priors, limiting their robust understanding of underlying physical dynamics. Reinforcement learning enhances physical grounding through exploration yet typically relies on external reward signals that remain isolated from the agent's internal states. World action models have emerged as a promising paradigm that integrates imagination and control to enable predictive planning. However, they rely on implicit context modeling, lacking explicit mechanisms for self-improvement. To solve these problems, we propose Self-Correcting VLA (SC-VLA), which achieve self-improvement by intrinsically guiding action refinement through sparse imagination. We first design sparse world imagination by integrating auxiliary predictive heads to forecast current task progress and future trajectory trends, thereby constraining the policy to encode short-term physical evolution. Then we introduce the online action refinement module to reshape progress-dependent dense rewards, adjusting trajectory orientation based on the predicted sparse future states. Evaluations on challenging robot manipulation tasks from simulation benchmarks and real-world settings demonstrate that SC-VLA achieve state-of-the-art performance, yielding the highest task throughput with 16% fewer steps and a 9% higher success rate than the best-performing baselines, alongside a 14% gain in real-world experiments. Code is available at https://github.com/Kisaragi0/SC-VLA.

标准视觉-语言-动作（VLA）模型依赖于拟合统计数据先验，限制了它们对潜在物理动力学的稳健理解。强化学习通过探索增强物理基础，但通常依赖于与代理内部状态保持隔离的外部奖励信号。世界行动模型已成为一种有前途的范式，它将想象力和控制结合起来以实现预测性规划。然而，他们依赖隐式上下文建模，缺乏明确的自我改进机制。为了解决这些问题，我们提出了自我修正VLA（SC-VLA），它通过稀疏想象力本质上指导行动细化来实现自我改进。我们首先通过集成辅助预测头来设计稀疏世界想象，以预测当前任务进展和未来轨迹趋势，从而约束编码短期物理演化的策略。然后，我们引入在线动作细化模块来重塑依赖于进度的密集奖励，根据预测的稀疏未来状态调整轨迹方向。根据模拟基准和现实环境对具有挑战性的机器人操作任务进行的评估表明，SC-VLA 实现了最先进的性能，与最佳性能基线相比，步骤减少了 16%，成功率提高了 9%，从而实现了最高的任务吞吐量，同时在现实实验中提高了 14%。代码可在 https://github.com/Kisaragi0/SC-VLA 获取。

</details>

---

## 2. Geometric Priors for Generalizable World Models via Vector Symbolic Architecture / 通过矢量符号体系结构的可推广世界模型的几何先验

**Date**: 2026-02-25 | **arXiv**: [2602.21467v1](http://arxiv.org/abs/2602.21467v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21467v1)

**Categories**: cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

A key challenge in artificial intelligence and neuroscience is understanding how neural systems learn representations that capture the underlying dynamics of the world. Most world models represent the transition function with unstructured neural networks, limiting interpretability, sample efficiency, and generalization to unseen states or action compositions. We address these issues with a generalizable world model grounded in Vector Symbolic Architecture (VSA) principles as geometric priors. Our approach utilizes learnable Fourier Holographic Reduced Representation (FHRR) encoders to map states and actions into a high dimensional complex vector space with learned group structure and models transitions with element-wise complex multiplication. We formalize the framework's group theoretic foundation and show how training such structured representations to be approximately invariant enables strong multi-step composition directly in latent space and generalization performances over various experiments. On a discrete grid world environment, our model achieves 87.5% zero shot accuracy to unseen state-action pairs, obtains 53.6% higher accuracy on 20-timestep horizon rollouts, and demonstrates 4x higher robustness to noise relative to an MLP baseline. These results highlight how training to have latent group structure yields generalizable, data-efficient, and interpretable world models, providing a principled pathway toward structured models for real-world planning and reasoning.

人工智能和神经科学的一个关键挑战是理解神经系统如何学习捕捉世界潜在动态的表征。大多数世界模型用非结构化神经网络表示转换函数，限制了可解释性、样本效率以及对未见状态或动作组合的泛化。我们使用基于矢量符号架构（VSA）原理作为几何先验的可概括的世界模型来解决这些问题。我们的方法利用可学习的傅里叶全息简化表示（FHRR）编码器将状态和动作映射到具有学习组结构的高维复杂向量空间中，并通过逐元素复杂乘法进行模型转换。我们形式化了该框架的群论基础，并展示了如何将这种结构化表示训练为近似不变，从而能够直接在潜在空间中实现强大的多步骤组合，并在各种实验中实现泛化性能。在离散网格世界环境中，我们的模型对未见过的状态-动作对实现了 87.5% 的零射击精度，在 20 时间步水平部署上获得了 53.6% 的更高精度，并且相对于 MLP 基线，对噪声的鲁棒性提高了 4 倍。这些结果强调了通过训练获得潜在群体结构如何产生可概括的、数据高效的和可解释的世界模型，为现实世界规划和推理的结构化模型提供了原则性途径。

</details>

---

## 3. Self-Curriculum Model-based Reinforcement Learning for Shape Control of Deformable Linear Objects / 基于自课程模型的可变形线性物体形状控制的强化学习

**Date**: 2026-02-25 | **arXiv**: [2602.21816v1](http://arxiv.org/abs/2602.21816v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21816v1)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Precise shape control of Deformable Linear Objects (DLOs) is crucial in robotic applications such as industrial and medical fields. However, existing methods face challenges in handling complex large deformation tasks, especially those involving opposite curvatures, and lack efficiency and precision. To address this, we propose a two-stage framework combining Reinforcement Learning (RL) and online visual servoing. In the large-deformation stage, a model-based reinforcement learning approach using an ensemble of dynamics models is introduced to significantly improve sample efficiency. Additionally, we design a self-curriculum goal generation mechanism that dynamically selects intermediate-difficulty goals with high diversity through imagined evaluations, thereby optimizing the policy learning process. In the small-deformation stage, a Jacobian-based visual servo controller is deployed to ensure high-precision convergence. Simulation results show that the proposed method enables efficient policy learning and significantly outperforms mainstream baselines in shape control success rate and precision. Furthermore, the framework effectively transfers the policy trained in simulation to real-world tasks with zero-shot adaptation. It successfully completes all 30 cases with diverse initial and target shapes across DLOs of different sizes and materials. The project website is available at: https://anonymous.4open.science/w/sc-mbrl-dlo-EB48/

可变形线性物体 (DLO) 的精确形状控制对于工业和医疗领域等机器人应用至关重要。然而，现有方法在处理复杂的大变形任务，特别是涉及相反曲率的任务时面临挑战，并且缺乏效率和精度。为了解决这个问题，我们提出了一个结合强化学习（RL）和在线视觉伺服的两阶段框架。在大变形阶段，引入了基于模型的强化学习方法，使用动力学模型集成来显着提高样本效率。此外，我们设计了一种自课程目标生成机制，通过想象评估动态选择具有高多样性的中等难度目标，从而优化策略学习过程。在小变形阶段，采用基于雅可比行列式的视觉伺服控制器，保证高精度收敛。仿真结果表明，该方法能够实现高效的策略学习，并且在形状控制成功率和精度方面显着优于主流基线。此外，该框架有效地将模拟训练的策略转移到零样本适应的现实世界任务中。它在不同尺寸和材料的 DLO 中成功完成了所有 30 个具有不同初始形状和目标形状的案例。该项目网站位于：https://anonymous.4open.science/w/sc-mbrl-dlo-EB48/

</details>

---



</details>

<details><summary><b>2026-02-25 (19 papers)</b></summary>

# arXiv World Model Papers - 2026-02-25

**Paper Count**: 19

---

## 1. Solaris: Building a Multiplayer Video World Model in Minecraft / Solaris：在 Minecraft 中构建多人视频世界模型

**Date**: 2026-02-25 | **arXiv**: [2602.22208v1](http://arxiv.org/abs/2602.22208v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.22208v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Existing action-conditioned video generation models (video world models) are limited to single-agent perspectives, failing to capture the multi-agent interactions of real-world environments. We introduce Solaris, a multiplayer video world model that simulates consistent multi-view observations. To enable this, we develop a multiplayer data system designed for robust, continuous, and automated data collection on video games such as Minecraft. Unlike prior platforms built for single-player settings, our system supports coordinated multi-agent interaction and synchronized videos + actions capture. Using this system, we collect 12.64 million multiplayer frames and propose an evaluation framework for multiplayer movement, memory, grounding, building, and view consistency. We train Solaris using a staged pipeline that progressively transitions from single-player to multiplayer modeling, combining bidirectional, causal, and Self Forcing training. In the final stage, we introduce Checkpointed Self Forcing, a memory-efficient Self Forcing variant that enables a longer-horizon teacher. Results show our architecture and training design outperform existing baselines. Through open-sourcing our system and models, we hope to lay the groundwork for a new generation of multi-agent world models.

现有的动作条件视频生成模型（视频世界模型）仅限于单智能体视角，无法捕捉现实世界环境的多智能体交互。我们介绍 Solaris，这是一种模拟一致的多视图观察的多人视频世界模型。为了实现这一目标，我们开发了一个多人数据系统，专为《我的世界》等视频游戏的稳健、连续和自动化数据收集而设计。与之前为单人游戏设置构建的平台不同，我们的系统支持协调的多代理交互和同步视频+动作捕捉。使用该系统，我们收集了 1264 万个多人游戏帧，并提出了多人运动、记忆、接地、构建和视图一致性的评估框架。我们使用分阶段的管道来训练 Solaris，该管道逐渐从单人模式过渡到多人模式，结合了双向、因果和自我强迫训练。在最后阶段，我们引入了检查点自我强迫，这是一种内存高效的自我强迫变体，可以实现更长视野的教师。结果显示我们的架构和培训设计优于现有基线。通过开源我们的系统和模型，我们希望为新一代多智能体世界模型奠定基础。

</details>

---

## 2. Geometry-as-context: Modulating Explicit 3D in Scene-consistent Video Generation to Geometry Context / 几何作为上下文：将场景一致视频生成中的显式 3D 调制为几何上下文

**Date**: 2026-02-25 | **arXiv**: [2602.21929v1](http://arxiv.org/abs/2602.21929v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21929v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Scene-consistent video generation aims to create videos that explore 3D scenes based on a camera trajectory. Previous methods rely on video generation models with external memory for consistency, or iterative 3D reconstruction and inpainting, which accumulate errors during inference due to incorrect intermediary outputs, non-differentiable processes, and separate models. To overcome these limitations, we introduce ``geometry-as-context". It iteratively completes the following steps using an autoregressive camera-controlled video generation model: (1) estimates the geometry of the current view necessary for 3D reconstruction, and (2) simulates and restores novel view images rendered by the 3D scene. Under this multi-task framework, we develop the camera gated attention module to enhance the model's capability to effectively leverage camera poses. During the training phase, text contexts are utilized to ascertain whether geometric or RGB images should be generated. To ensure that the model can generate RGB-only outputs during inference, the geometry context is randomly dropped from the interleaved text-image-geometry training sequence. The method has been tested on scene video generation with one-direction and forth-and-back trajectories. The results show its superiority over previous approaches in maintaining scene consistency and camera control.

场景一致的视频生成旨在创建基于摄像机轨迹探索 3D 场景的视频。以前的方法依赖具有外部存储器的视频生成模型来实现一致性，或者迭代 3D 重建和修复，这会在推理过程中由于不正确的中间输出、不可微分的过程和单独的模型而累积错误。为了克服这些限制，我们引入了“几何即上下文”。它使用自回归相机控制的视频生成模型迭代地完成以下步骤：（1）估计 3D 重建所需的当前视图的几何形状，以及（2）模拟和恢复 3D 场景渲染的新视图图像。在这个多任务框架下，我们开发了相机门控注意力模块，以增强模型有效利用相机姿势的能力。在训练阶段，利用文本上下文为了确定应该生成几何图像还是 RGB 图像，为了确保模型在推理过程中可以生成仅 RGB 的输出，从交错的文本-图像-几何训练序列中随机删除该方法，并在单向和前后轨迹的场景视频生成上进行了测试，结果表明其在保持场景一致性和摄像机控制方面优于以前的方法。

</details>

---

## 3. Understanding Annotation Error Propagation and Learning an Adaptive Policy for Expert Intervention in Barrett's Video Segmentation / 了解注释错误传播并学习巴雷特视频分割中专家干预的自适应策略

**Date**: 2026-02-25 | **arXiv**: [2602.21855v1](http://arxiv.org/abs/2602.21855v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21855v1)

**Categories**: cs.CV, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Accurate annotation of endoscopic videos is essential yet time-consuming, particularly for challenging datasets such as dysplasia in Barrett's esophagus, where the affected regions are irregular and lack clear boundaries. Semi-automatic tools like Segment Anything Model 2 (SAM2) can ease this process by propagating annotations across frames, but small errors often accumulate and reduce accuracy, requiring expert review and correction. To address this, we systematically study how annotation errors propagate across different prompt types, namely masks, boxes, and points, and propose Learning-to-Re-Prompt (L2RP), a cost-aware framework that learns when and where to seek expert input. By tuning a human-cost parameter, our method balances annotation effort and segmentation accuracy. Experiments on a private Barrett's dysplasia dataset and the public SUN-SEG benchmark demonstrate improved temporal consistency and superior performance over baseline strategies.

内窥镜视频的准确注释至关重要但又耗时，特别是对于具有挑战性的数据集，例如巴雷特食管的发育不良，其中受影响的区域不规则且缺乏清晰的边界。 Segment Anything Model 2 (SAM2) 等半自动工具可以通过跨帧传播注释来简化此过程，但小错误常常会累积并降低准确性，需要专家审查和纠正。为了解决这个问题，我们系统地研究了注释错误如何在不同的提示类型（即掩码、框和点）之间传播，并提出了学习重新提示（L2RP），这是一种成本感知框架，可以学习何时何地寻求专家输入。通过调整人力成本参数，我们的方法平衡了注释工作和分割准确性。在私人 Barrett 发育不良数据集和公共 SUN-SEG 基准上进行的实验表明，与基线策略相比，时间一致性得到了改善，性能也更优越。

</details>

---

## 4. UniVBench: Towards Unified Evaluation for Video Foundation Models / UniVBench：迈向视频基础模型的统一评估

**Date**: 2026-02-25 | **arXiv**: [2602.21835v1](http://arxiv.org/abs/2602.21835v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21835v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Video foundation models aim to integrate video understanding, generation, editing, and instruction following within a single framework, making them a central direction for next-generation multimodal systems. However, existing evaluation benchmarks remain fragmented and limited in scope, as they each target a single task, rely on task-specific metrics, and typically use short or simple video clips. As a result, they do not capture the unified capabilities that these models are designed to deliver. To address this gap, we introduce UniVBench, a benchmark purpose-built for evaluating video foundation models across four core abilities: video understanding, video generation, video editing, and a newly proposed task, video reconstruction, which assesses how faithfully a model can reproduce video content it has encountered. Our benchmark substantially expands the complexity of evaluation by incorporating 200 high-quality, diverse and multi-shot videos, each paired with detailed captions, multi-format editing instructions, and reference images. All videos are human-created and carefully validated, offering richer cinematic information than prior benchmarks. In addition, we develop a unified agentic evaluation system (UniV-Eval) that standardizes prompting, instruction parsing, and scoring across all tasks, enabling fair, scalable, and reproducible comparisons of unified video models. By grounding evaluation in instruction-based multi-shot video tasks, UniVBench provides the first framework for measuring the integrated capabilities that video foundation models aim to achieve. Extensive human annotations ensure our evaluation aligns with human judgment, enabling rigorous assessment and accelerating progress toward robust video intelligence.

视频基础模型旨在将视频理解、生成、编辑和指令跟踪集成在一个框架内，使其成为下一代多模态系统的中心方向。然而，现有的评估基准仍然分散且范围有限，因为它们每个都针对单个任务，依赖于特定于任务的指标，并且通常使用短或简单的视频剪辑。因此，它们无法捕获这些模型旨在提供的统一功能。为了解决这一差距，我们引入了 UniVBench，这是一个专门为评估视频基础模型的四个核心能力而构建的基准：视频理解、视频生成、视频编辑，以及新提出的任务视频重建，该任务评估模型如何忠实地再现其遇到的视频内容。我们的基准测试通过纳入 200 个高质量、多样化的多镜头视频，每个视频都配有详细的标题、多格式编辑说明和参考图像，极大地扩展了评估的复杂性。所有视频均由人工创作并经过仔细验证，提供比之前的基准更丰富的电影信息。此外，我们开发了一个统一的代理评估系统（UniV-Eval），该系统标准化了所有任务的提示、指令解析和评分，从而实现了统一视频模型的公平、可扩展和可重复的比较。通过在基于指令的多镜头视频任务中进行基础评估，UniVBench 提供了第一个用于测量视频基础模型旨在实现的集成功能的框架。广泛的人工注释确保我们的评估与人类判断一致，从而实现严格的评估并加速实现强大的视频智能。

</details>

---

## 5. SkyReels-V4: Multi-modal Video-Audio Generation, Inpainting and Editing model / SkyReels-V4：多模式视频音频生成、修复和编辑模型

**Date**: 2026-02-25 | **arXiv**: [2602.21818v1](http://arxiv.org/abs/2602.21818v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21818v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

SkyReels V4 is a unified multi modal video foundation model for joint video audio generation, inpainting, and editing. The model adopts a dual stream Multimodal Diffusion Transformer (MMDiT) architecture, where one branch synthesizes video and the other generates temporally aligned audio, while sharing a powerful text encoder based on the Multimodal Large Language Models (MMLM). SkyReels V4 accepts rich multi modal instructions, including text, images, video clips, masks, and audio references. By combining the MMLMs multi modal instruction following capability with in context learning in the video branch MMDiT, the model can inject fine grained visual guidance under complex conditioning, while the audio branch MMDiT simultaneously leverages audio references to guide sound generation. On the video side, we adopt a channel concatenation formulation that unifies a wide range of inpainting style tasks, such as image to video, video extension, and video editing under a single interface, and naturally extends to vision referenced inpainting and editing via multi modal prompts. SkyReels V4 supports up to 1080p resolution, 32 FPS, and 15 second duration, enabling high fidelity, multi shot, cinema level video generation with synchronized audio. To make such high resolution, long-duration generation computationally feasible, we introduce an efficiency strategy: Joint generation of low resolution full sequences and high-resolution keyframes, followed by dedicated super-resolution and frame interpolation models. To our knowledge, SkyReels V4 is the first video foundation model that simultaneously supports multi-modal input, joint video audio generation, and a unified treatment of generation, inpainting, and editing, while maintaining strong efficiency and quality at cinematic resolutions and durations.

SkyReels V4 是一个统一的多模态视频基础模型，用于联合视频音频生成、修复和编辑。该模型采用双流多模态扩散变压器（MMDiT）架构，其中一个分支合成视频，另一个分支生成时间对齐的音频，同时共享基于多模态大语言模型（MMLM）的强大文本编码器。 SkyReels V4 接受丰富的多模式指令，包括文本、图像、视频剪辑、蒙版和音频参考。通过将 MMLM 多模态指令跟随功能与视频分支 MMDiT 中的上下文学习相结合，该模型可以在复杂条件下注入细粒度的视觉指导，而音频分支 MMDiT 同时利用音频参考来指导声音生成。在视频方面，我们采用通道串联公式，将图像到视频、视频扩展和视频编辑等多种修复风格任务统一在一个界面下，并通过多模式提示自然扩展到视觉参考修复和编辑。 SkyReels V4 支持高达 1080p 的分辨率、32 FPS 和 15 秒的持续时间，可生成具有同步音频的高保真、多镜头、影院级视频。为了使这种高分辨率、长时间的生成在计算上可行，我们引入了一种效率策略：联合生成低分辨率全序列和高分辨率关键帧，然后是专用的超分辨率和帧插值模型。据我们所知，SkyReels V4是第一个同时支持多模态输入、联合视频音频生成以及生成、修复和编辑统一处理的视频基础模型，同时在电影分辨率和时长上保持强大的效率和质量。

</details>

---

## 6. MultiAnimate: Pose-Guided Image Animation Made Extensible / MultiAnimate：可扩展的姿势引导图像动画

**Date**: 2026-02-25 | **arXiv**: [2602.21581v1](http://arxiv.org/abs/2602.21581v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21581v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Pose-guided human image animation aims to synthesize realistic videos of a reference character driven by a sequence of poses. While diffusion-based methods have achieved remarkable success, most existing approaches are limited to single-character animation. We observe that naively extending these methods to multi-character scenarios often leads to identity confusion and implausible occlusions between characters. To address these challenges, in this paper, we propose an extensible multi-character image animation framework built upon modern Diffusion Transformers (DiTs) for video generation. At its core, our framework introduces two novel components-Identifier Assigner and Identifier Adapter - which collaboratively capture per-person positional cues and inter-person spatial relationships. This mask-driven scheme, along with a scalable training strategy, not only enhances flexibility but also enables generalization to scenarios with more characters than those seen during training. Remarkably, trained on only a two-character dataset, our model generalizes to multi-character animation while maintaining compatibility with single-character cases. Extensive experiments demonstrate that our approach achieves state-of-the-art performance in multi-character image animation, surpassing existing diffusion-based baselines.

姿势引导的人体图像动画旨在合成由一系列姿势驱动的参考角色的逼真视频。虽然基于扩散的方法取得了显着的成功，但大多数现有方法仅限于单角色动画。我们观察到，天真地将这些方法扩展到多角色场景通常会导致角色之间的身份混乱和令人难以置信的遮挡。为了解决这些挑战，在本文中，我们提出了一种基于现代扩散变压器（DiT）的可扩展多字符图像动画框架，用于视频生成。我们的框架的核心引入了两个新颖的组件——标识符分配器和标识符适配器——它们协作捕获每个人的位置线索和人与人之间的空间关系。这种掩码驱动的方案以及可扩展的训练策略不仅增强了灵活性，而且还能够泛化到比训练期间看到的字符更多的场景。值得注意的是，我们的模型仅在两个字符数据集上进行训练，可推广到多字符动画，同时保持与单字符情况的兼容性。大量的实验表明，我们的方法在多字符图像动画中实现了最先进的性能，超越了现有的基于扩散的基线。

</details>

---

## 7. Exploring Vision-Language Models for Open-Vocabulary Zero-Shot Action Segmentation / 探索开放词汇零样本动作分割的视觉语言模型

**Date**: 2026-02-24 | **arXiv**: [2602.21406v1](http://arxiv.org/abs/2602.21406v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21406v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Temporal Action Segmentation (TAS) requires dividing videos into action segments, yet the vast space of activities and alternative breakdowns makes collecting comprehensive datasets infeasible. Existing methods remain limited to closed vocabularies and fixed label sets. In this work, we explore the largely unexplored problem of Open-Vocabulary Zero-Shot Temporal Action Segmentation (OVTAS) by leveraging the strong zero-shot capabilities of Vision-Language Models (VLMs). We introduce a training-free pipeline that follows a segmentation-by-classification design: Frame-Action Embedding Similarity (FAES) matches video frames to candidate action labels, and Similarity-Matrix Temporal Segmentation (SMTS) enforces temporal consistency. Beyond proposing OVTAS, we present a systematic study across 14 diverse VLMs, providing the first broad analysis of their suitability for open-vocabulary action segmentation. Experiments on standard benchmarks show that OVTAS achieves strong results without task-specific supervision, underscoring the potential of VLMs for structured temporal understanding.

时间动作分割（TAS）需要将视频划分为动作片段，但巨大的活动空间和替代细分使得收集全面的数据集变得不可行。现有方法仍然仅限于封闭词汇表和固定标签集。在这项工作中，我们通过利用视觉语言模型（VLM）强大的零样本能力来探索开放词汇零样本时间动作分割（OVTAS）的很大程度上未被探索的问题。我们引入了一种遵循按分类分割设计的免训练管道：帧动作嵌入相似性（FAES）将视频帧与候选动作标签相匹配，相似性矩阵时间分割（SMTS）强制时间一致性。除了提出 OVTAS 之外，我们还对 14 个不同的 VLM 进行了系统研究，首次对其开放词汇动作分割的适用性进行了广泛分析。标准基准测试的实验表明，OVTAS 在没有特定于任务的监督的情况下取得了很好的结果，强调了 VLM 在结构化时间理解方面的潜力。

</details>

---

## 8. Towards Controllable Video Synthesis of Routine and Rare OR Events / 实现常规和罕见手术事件的可控视频合成

**Date**: 2026-02-24 | **arXiv**: [2602.21365v1](http://arxiv.org/abs/2602.21365v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21365v1)

**Categories**: cs.CV, cs.AI, cs.LG, eess.IV

<details><summary><b>Abstract / 摘要</b></summary>

Purpose: Curating large-scale datasets of operating room (OR) workflow, encompassing rare, safety-critical, or atypical events, remains operationally and ethically challenging. This data bottleneck complicates the development of ambient intelligence for detecting, understanding, and mitigating rare or safety-critical events in the OR.   Methods: This work presents an OR video diffusion framework that enables controlled synthesis of rare and safety-critical events. The framework integrates a geometric abstraction module, a conditioning module, and a fine-tuned diffusion model to first transform OR scenes into abstract geometric representations, then condition the synthesis process, and finally generate realistic OR event videos. Using this framework, we also curate a synthetic dataset to train and validate AI models for detecting near-misses of sterile-field violations.   Results: In synthesizing routine OR events, our method outperforms off-the-shelf video diffusion baselines, achieving lower FVD/LPIPS and higher SSIM/PSNR in both in- and out-of-domain datasets. Through qualitative results, we illustrate its ability for controlled video synthesis of counterfactual events. An AI model trained and validated on the generated synthetic data achieved a RECALL of 70.13% in detecting near safety-critical events. Finally, we conduct an ablation study to quantify performance gains from key design choices.   Conclusion: Our solution enables controlled synthesis of routine and rare OR events from abstract geometric representations. Beyond demonstrating its capability to generate rare and safety-critical scenarios, we show its potential to support the development of ambient intelligence models.

目的：整理包含罕见、安全关键或非典型事件的手术室 (OR) 工作流程的大规模数据集，在操作和道德上仍然具有挑战性。这一数据瓶颈使得用于检测、理解和缓解手术室中罕见或安全关键事件的环境智能的开发变得复杂。   方法：这项工作提出了一个 OR 视频扩散框架，可以控制罕见和安全关键事件的合成。该框架集成了几何抽象模块、调节模块和微调扩散模型，首先将 OR 场景转换为抽象几何表示，然后调节合成过程，最后生成逼真的 OR 事件视频。使用这个框架，我们还整理了一个合成数据集来训练和验证人工智能模型，以检测无菌区违规事件的险情。   结果：在合成常规 OR 事件时，我们的方法优于现成的视频扩散基线，在域内和域外数据集中实现了较低的 FVD/LPIPS 和较高的 SSIM/PSNR。通过定性结果，我们说明了其对反事实事件进行受控视频合成的能力。根据生成的合成数据进行训练和验证的 AI 模型在检测临近安全关键事件时实现了 70.13% 的召回率。最后，我们进行了一项消融研究，以量化关键设计选择带来的性能增益。   结论：我们的解决方案能够从抽象几何表示中控制合成常规和罕见的 OR 事件。除了展示其生成罕见和安全关键场景的能力之外，我们还展示了其支持环境智能模型开发的潜力。

</details>

---

## 9. HorizonForge: Driving Scene Editing with Any Trajectories and Any Vehicles / Horizo​​nForge：使用任何轨迹和任何车辆进行驾驶场景编辑

**Date**: 2026-02-24 | **arXiv**: [2602.21333v1](http://arxiv.org/abs/2602.21333v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21333v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Controllable driving scene generation is critical for realistic and scalable autonomous driving simulation, yet existing approaches struggle to jointly achieve photorealism and precise control. We introduce HorizonForge, a unified framework that reconstructs scenes as editable Gaussian Splats and Meshes, enabling fine-grained 3D manipulation and language-driven vehicle insertion. Edits are rendered through a noise-aware video diffusion process that enforces spatial and temporal consistency, producing diverse scene variations in a single feed-forward pass without per-trajectory optimization. To standardize evaluation, we further propose HorizonSuite, a comprehensive benchmark spanning ego- and agent-level editing tasks such as trajectory modifications and object manipulation. Extensive experiments show that Gaussian-Mesh representation delivers substantially higher fidelity than alternative 3D representations, and that temporal priors from video diffusion are essential for coherent synthesis. Combining these findings, HorizonForge establishes a simple yet powerful paradigm for photorealistic, controllable driving simulation, achieving an 83.4% user-preference gain and a 25.19% FID improvement over the second best state-of-the-art method. Project page: https://horizonforge.github.io/ .

可控驾驶场景生成对于真实且可扩展的自动驾驶模拟至关重要，但现有方法很难同时实现照片真实感和精确控制。我们推出了 Horizo​​nForge，这是一个统一的框架，可将场景重建为可编辑的高斯图和网格，从而实现细粒度的 3D 操作和语言驱动的车辆插入。编辑是通过噪声感知视频扩散过程进行渲染的，该过程强制执行空间和时间一致性，在单个前馈通道中产生不同的场景变化，而无需每个轨迹优化。为了标准化评估，我们进一步提出了 Horizo​​nSuite，这是一个涵盖自我和代理级别编辑任务（例如轨迹修改和对象操作）的综合基准。大量实验表明，高斯网格表示比其他 3D 表示具有更高的保真度，并且视频扩散的时间先验对于相干合成至关重要。结合这些发现，Horizo​​nForge 建立了一个简单而强大的范例，用于逼真、可控的驾驶模拟，与第二最佳的最先进方法相比，实现了 83.4% 的用户偏好增益和 25.19% 的 FID 改进。项目页面：https://horizo​​nforge.github.io/。

</details>

---

## 10. Human Video Generation from a Single Image with 3D Pose and View Control / 通过 3D 姿势和视图控制从单个图像生成人体视频

**Date**: 2026-02-24 | **arXiv**: [2602.21188v1](http://arxiv.org/abs/2602.21188v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21188v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Recent diffusion methods have made significant progress in generating videos from single images due to their powerful visual generation capabilities. However, challenges persist in image-to-video synthesis, particularly in human video generation, where inferring view-consistent, motion-dependent clothing wrinkles from a single image remains a formidable problem. In this paper, we present Human Video Generation in 4D (HVG), a latent video diffusion model capable of generating high-quality, multi-view, spatiotemporally coherent human videos from a single image with 3D pose and view control. HVG achieves this through three key designs: (i) Articulated Pose Modulation, which captures the anatomical relationships of 3D joints via a novel dual-dimensional bone map and resolves self-occlusions across views by introducing 3D information; (ii) View and Temporal Alignment, which ensures multi-view consistency and alignment between a reference image and pose sequences for frame-to-frame stability; and (iii) Progressive Spatio-Temporal Sampling with temporal alignment to maintain smooth transitions in long multi-view animations. Extensive experiments on image-to-video tasks demonstrate that HVG outperforms existing methods in generating high-quality 4D human videos from diverse human images and pose inputs.

最近的扩散方法由于其强大的视觉生成能力，在从单个图像生成视频方面取得了重大进展。然而，图像到视频的合成仍然存在挑战，特别是在人类视频生成方面，从单个图像推断视图一致、运动相关的衣服皱纹仍然是一个艰巨的问题。在本文中，我们提出了 4D 人类视频生成 (HVG)，这是一种潜在视频扩散模型，能够从具有 3D 姿势和视图控制的单个图像生成高质量、多视图、时空连贯的人类视频。 HVG 通过三个关键设计实现了这一目标：(i) 关节姿势调制，通过新颖的二维骨图捕获 3D 关节的解剖关系，并通过引入 3D 信息解决跨视图的自遮挡问题； (ii) 视图和时间对齐，确保参考图像和姿势序列之间的多视图一致性和对齐，以实现帧到帧的稳定性； (iii) 渐进式时空采样与时间对齐，以保持长多视图动画中的平滑过渡。对图像到视频任务的大量实验表明，HVG 在从不同的人类图像和姿势输入生成高质量 4D 人类视频方面优于现有方法。

</details>

---

## 11. UDVideoQA: A Traffic Video Question Answering Dataset for Multi-Object Spatio-Temporal Reasoning in Urban Dynamics / UDVideoQA：用于城市动力学中多对象时空推理的交通视频问答数据集

**Date**: 2026-02-24 | **arXiv**: [2602.21137v1](http://arxiv.org/abs/2602.21137v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.21137v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Understanding the complex, multi-agent dynamics of urban traffic remains a fundamental challenge for video language models. This paper introduces Urban Dynamics VideoQA, a benchmark dataset that captures the unscripted real-world behavior of dynamic urban scenes. UDVideoQA is curated from 16 hours of traffic footage recorded at multiple city intersections under diverse traffic, weather, and lighting conditions. It employs an event-driven dynamic blur technique to ensure privacy preservation without compromising scene fidelity. Using a unified annotation pipeline, the dataset contains 28K question-answer pairs generated across 8 hours of densely annotated video, averaging one question per second. Its taxonomy follows a hierarchical reasoning level, spanning basic understanding and attribution to event reasoning, reverse reasoning, and counterfactual inference, enabling systematic evaluation of both visual grounding and causal reasoning. Comprehensive experiments benchmark 10 SOTA VideoLMs on UDVideoQA and 8 models on a complementary video question generation benchmark. Results reveal a persistent perception-reasoning gap, showing models that excel in abstract inference often fail with fundamental visual grounding. While models like Gemini Pro achieve the highest zero-shot accuracy, fine-tuning the smaller Qwen2.5-VL 7B model on UDVideoQA bridges this gap, achieving performance comparable to proprietary systems. In VideoQGen, Gemini 2.5 Pro, and Qwen3 Max generate the most relevant and complex questions, though all models exhibit limited linguistic diversity, underscoring the need for human-centric evaluation. The UDVideoQA suite, including the dataset, annotation tools, and benchmarks for both VideoQA and VideoQGen, provides a foundation for advancing robust, privacy-aware, and real-world multimodal reasoning. UDVideoQA is available at https://ud-videoqa.github.io/UD-VideoQA/UD-VideoQA/.

了解城市交通复杂的多智能体动态仍然是视频语言模型的基本挑战。本文介绍了 Urban Dynamics VideoQA，这是一个基准数据集，可捕获动态城市场景的无脚本现实行为。 UDVideoQA 根据在不同交通、天气和照明条件下在多个城市十字路口录制的 16 小时交通录像进行整理。它采用事件驱动的动态模糊技术来确保隐私保护，同时又不影响场景保真度。使用统一的注释管道，该数据集包含在 8 小时的密集注释视频中生成的 28K 问答对，平均每秒一个问题。其分类遵循分层推理水平，涵盖对事件推理、逆向推理和反事实推理的基本理解和归因，从而能够对视觉基础和因果推理进行系统评估。综合实验在 UDVideoQA 上对 10 个 SOTA VideoLM 进行基准测试，在补充视频问题生成基准上对 8 个模型进行基准测试。结果揭示了持续存在的感知推理差距，表明擅长抽象推理的模型往往在基本视觉基础上失败。虽然 Gemini Pro 等模型实现了最高的零射击精度，但在 UDVideoQA 上微调较小的 Qwen2.5-VL 7B 模型弥补了这一差距，实现了与专有系统相当的性能。在 VideoQGen、Gemini 2.5 Pro 和 Qwen3 Max 中，尽管所有模型都表现出有限的语言多样性，但生成了最相关和最复杂的问题，这强调了以人为中心的评估的必要性。 UDVideoQA 套件包括数据集、注释工具以及 VideoQA 和 VideoQGen 的基准，为推进稳健、隐私意识和现实世界的多模态推理奠定了基础。 UDVideoQA 位于 https://ud-videoqa.github.io/UD-VideoQA/UD-VideoQA/。

</details>

---

## 12. VII: Visual Instruction Injection for Jailbreaking Image-to-Video Generation Models / VII：越狱图像到视频生成模型的视觉指令注入

**Date**: 2026-02-24 | **arXiv**: [2602.20999v1](http://arxiv.org/abs/2602.20999v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.20999v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Image-to-Video (I2V) generation models, which condition video generation on reference images, have shown emerging visual instruction-following capability, allowing certain visual cues in reference images to act as implicit control signals for video generation. However, this capability also introduces a previously overlooked risk: adversaries may exploit visual instructions to inject malicious intent through the image modality. In this work, we uncover this risk by proposing Visual Instruction Injection (VII), a training-free and transferable jailbreaking framework that intentionally disguises the malicious intent of unsafe text prompts as benign visual instructions in the safe reference image. Specifically, VII coordinates a Malicious Intent Reprogramming module to distill malicious intent from unsafe text prompts while minimizing their static harmfulness, and a Visual Instruction Grounding module to ground the distilled intent onto a safe input image by rendering visual instructions that preserve semantic consistency with the original unsafe text prompt, thereby inducing harmful content during I2V generation. Empirically, our extensive experiments on four state-of-the-art commercial I2V models (Kling-v2.5-turbo, Gemini Veo-3.1, Seedance-1.5-pro, and PixVerse-V5) demonstrate that VII achieves Attack Success Rates of up to 83.5% while reducing Refusal Rates to near zero, significantly outperforming existing baselines.

图像到视频 (I2V) 生成模型在参考图像上调节视频生成，已显示出新兴的视觉指令跟踪功能，允许参考图像中的某些视觉提示充当视频生成的隐式控制信号。然而，这种功能也带来了一个以前被忽视的风险：对手可能会利用视觉指令通过图像模态注入恶意意图。在这项工作中，我们通过提出视觉指令注入（VII）来揭示这一风险，这是一种免训练且可转移的越狱框架，有意将不安全文本提示的恶意意图伪装成安全参考图像中的良性视觉指令。具体来说，VII 协调恶意意图重新编程模块，从不安全文本提示中提取恶意意图，同时最大限度地减少其静态危害性，并协调视觉指令接地模块，通过渲染与原始不安全文本提示保持语义一致性的视觉指令，将提取的意图接地到安全输入图像上，从而在 I2V 生成过程中引入有害内容。根据经验，我们对四种最先进的商业 I2V 模型（Kling-v2.5-turbo、Gemini Veo-3.1、Seedance-1.5-pro 和 PixVerse-V5）进行的广泛实验表明，VII 的攻击成功率高达 83.5%，同时将拒绝率降低到接近零，显着优于现有基线。

</details>

---

## 13. LongVideo-R1: Smart Navigation for Low-cost Long Video Understanding / LongVideo-R1：低成本长视频理解的智能导航

**Date**: 2026-02-24 | **arXiv**: [2602.20913v1](http://arxiv.org/abs/2602.20913v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.20913v1)

**Categories**: cs.CV

**Code**: https://github.com/qiujihao19/LongVideo-R1

<details><summary><b>Abstract / 摘要</b></summary>

This paper addresses the critical and underexplored challenge of long video understanding with low computational budgets. We propose LongVideo-R1, an active, reasoning-equipped multimodal large language model (MLLM) agent designed for efficient video context navigation, avoiding the redundancy of exhaustive search. At the core of LongVideo-R1 lies a reasoning module that leverages high-level visual cues to infer the most informative video clip for subsequent processing. During inference, the agent initiates traversal from top-level visual summaries and iteratively refines its focus, immediately halting the exploration process upon acquiring sufficient knowledge to answer the query. To facilitate training, we first extract hierarchical video captions from CGBench, a video corpus with grounding annotations, and guide GPT-5 to generate 33K high-quality chain-of-thought-with-tool trajectories. The LongVideo-R1 agent is fine-tuned upon the Qwen-3-8B model through a two-stage paradigm: supervised fine-tuning (SFT) followed by reinforcement learning (RL), where RL employs a specifically designed reward function to maximize selective and efficient clip navigation. Experiments on multiple long video benchmarks validate the effectiveness of name, which enjoys superior tradeoff between QA accuracy and efficiency. All curated data and source code are provided in the supplementary material and will be made publicly available. Code and data are available at: https://github.com/qiujihao19/LongVideo-R1

本文解决了低计算预算下长视频理解的关键且尚未充分探索的挑战。我们提出了 LongVideo-R1，一种主动的、配备推理的多模态大语言模型（MLLM）代理，设计用于高效的视频上下文导航，避免详尽搜索的冗余。 LongVideo-R1 的核心是一个推理模块，它利用高级视觉线索来推断信息最丰富的视频剪辑，以供后续处理。在推理过程中，代理从顶级视觉摘要开始遍历，并迭代地细化其焦点，在获得足够的知识来回答查询后立即停止探索过程。为了便于训练，我们首先从带有基础注释的视频语料库 CGBench 中提取分层视频字幕，并引导 GPT-5 生成 33K 高质量的思想链工具轨迹。 LongVideo-R1 代理通过两阶段范式在 Qwen-3-8B 模型上进行微调：监督微调 (SFT)，然后是强化学习 (RL)，其中 RL 采用专门设计的奖励函数来最大限度地提高选择性和高效的剪辑导航。在多个长视频基准上进行的实验验证了 name 的有效性，它在 QA 准确性和效率之间享有卓越的权衡。所有精选数据和源代码均在补充材料中提供，并将公开发布。代码和数据可参见：https://github.com/qiujihao19/LongVideo-R1

</details>

---

## 14. PyVision-RL: Forging Open Agentic Vision Models via RL / PyVision-RL：通过 RL 打造开放代理视觉模型

**Date**: 2026-02-24 | **arXiv**: [2602.20739v1](http://arxiv.org/abs/2602.20739v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.20739v1)

**Categories**: cs.AI, cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Reinforcement learning for agentic multimodal models often suffers from interaction collapse, where models learn to reduce tool usage and multi-turn reasoning, limiting the benefits of agentic behavior. We introduce PyVision-RL, a reinforcement learning framework for open-weight multimodal models that stabilizes training and sustains interaction. Our approach combines an oversampling-filtering-ranking rollout strategy with an accumulative tool reward to prevent collapse and encourage multi-turn tool use. Using a unified training pipeline, we develop PyVision-Image and PyVision-Video for image and video understanding. For video reasoning, PyVision-Video employs on-demand context construction, selectively sampling task-relevant frames during reasoning to significantly reduce visual token usage. Experiments show strong performance and improved efficiency, demonstrating that sustained interaction and on-demand visual processing are critical for scalable multimodal agents.

代理多模态模型的强化学习经常会遇到交互崩溃的问题，其中模型学习减少工具使用和多轮推理，从而限制了代理行为的好处。我们引入了 PyVision-RL，这是一种用于开放权重多模态模型的强化学习框架，可以稳定训练并维持交互。我们的方法将过采样-过滤-排名推出策略与累积工具奖励相结合，以防止崩溃并鼓励多回合工具的使用。使用统一的训练管道，我们开发了 PyVision-Image 和 PyVision-Video 用于图像和视频理解。对于视频推理，PyVision-Video 采用按需上下文构建，在推理过程中选择性地采样与任务相关的帧，以显着减少视觉标记的使用。实验显示出强大的性能和更高的效率，证明持续交互和按需视觉处理对于可扩展的多模式代理至关重要。

</details>

---

## 15. RAYNOVA: Scale-Temporal Autoregressive World Modeling in Ray Space / RAYNOVA：射线空间中的尺度时间自回归世界建模

**Date**: 2026-02-24 | **arXiv**: [2602.20685v2](http://arxiv.org/abs/2602.20685v2) | **PDF**: [Link](http://arxiv.org/pdf/2602.20685v2)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

World foundation models aim to simulate the evolution of the real world with physically plausible behavior. Unlike prior methods that handle spatial and temporal correlations separately, we propose RAYNOVA, a geometry-agonistic multiview world model for driving scenarios that employs a dual-causal autoregressive framework. It follows both scale-wise and temporal topological orders in the autoregressive process, and leverages global attention for unified 4D spatio-temporal reasoning. Different from existing works that impose strong 3D geometric priors, RAYNOVA constructs an isotropic spatio-temporal representation across views, frames, and scales based on relative Plücker-ray positional encoding, enabling robust generalization to diverse camera setups and ego motions. We further introduce a recurrent training paradigm to alleviate distribution drift in long-horizon video generation. RAYNOVA achieves state-of-the-art multi-view video generation results on nuScenes, while offering higher throughput and strong controllability under diverse input conditions, generalizing to novel views and camera configurations without explicit 3D scene representation. Our code will be released at https://raynova-ai.github.io/.

世界基础模型旨在通过物理上合理的行为来模拟现实世界的演化。与之前分别处理空间和时间相关性的方法不同，我们提出了 RAYNOVA，这是一种采用双因果自回归框架的驾驶场景的几何对抗多视图世界模型。它在自回归过程中遵循尺度和时间拓扑顺序，并利用全局注意力进行统一的 4D 时空推理。与强加强 3D 几何先验的现有作品不同，RAYNOVA 基于相对 Plücker 射线位置编码构建了跨视图、帧和尺度的各向同性时空表示，从而能够对不同的相机设置和自我运动进行稳健的泛化。我们进一步引入了一种循环训练范例，以减轻长视野视频生成中的分布漂移。 RAYNOVA 在 nuScenes 上实现了最先进的多视图视频生成结果，同时在不同的输入条件下提供更高的吞吐量和强大的可控性，推广到新颖的视图和相机配置，而无需明确的 3D 场景表示。我们的代码将在 https://raynova-ai.github.io/ 发布。

</details>

---

## 16. GA-Drive: Geometry-Appearance Decoupled Modeling for Free-viewpoint Driving Scene Generatio / GA-Drive：用于自由视点驾驶场景生成的几何外观解耦建模

**Date**: 2026-02-24 | **arXiv**: [2602.20673v1](http://arxiv.org/abs/2602.20673v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.20673v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

A free-viewpoint, editable, and high-fidelity driving simulator is crucial for training and evaluating end-to-end autonomous driving systems. In this paper, we present GA-Drive, a novel simulation framework capable of generating camera views along user-specified novel trajectories through Geometry-Appearance Decoupling and Diffusion-Based Generation. Given a set of images captured along a recorded trajectory and the corresponding scene geometry, GA-Drive synthesizes novel pseudo-views using geometry information. These pseudo-views are then transformed into photorealistic views using a trained video diffusion model. In this way, we decouple the geometry and appearance of scenes. An advantage of such decoupling is its support for appearance editing via state-of-the-art video-to-video editing techniques, while preserving the underlying geometry, enabling consistent edits across both original and novel trajectories. Extensive experiments demonstrate that GA-Drive substantially outperforms existing methods in terms of NTA-IoU, NTL-IoU, and FID scores.

自由视角、可编辑且高保真的驾驶模拟器对于训练和评估端到端自动驾驶系统至关重要。在本文中，我们提出了 GA-Drive，这是一种新颖的模拟框架，能够通过几何外观解耦和基于扩散的生成沿着用户指定的新颖轨迹生成相机视图。给定沿着记录轨迹捕获的一组图像和相应的场景几何形状，GA-Drive 使用几何信息合成新颖的伪视图。然后使用经过训练的视频扩散模型将这些伪视图转换为逼真的视图。通过这种方式，我们将场景的几何形状和外观解耦。这种解耦的一个优点是它支持通过最先进的视频到视频编辑技术进行外观编辑，同时保留底层几何形状，从而能够在原始和新颖的轨迹上进行一致的编辑。大量实验表明，GA-Drive 在 NTA-IoU、NTL-IoU 和 FID 分数方面明显优于现有方法。

</details>

---

## 17. AnimeAgent: Is the Multi-Agent via Image-to-Video models a Good Disney Storytelling Artist? / AnimeAgent：通过图像到视频模型的多代理是优秀的迪士尼讲故事艺术家吗？

**Date**: 2026-02-24 | **arXiv**: [2602.20664v1](http://arxiv.org/abs/2602.20664v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.20664v1)

**Categories**: cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Custom Storyboard Generation (CSG) aims to produce high-quality, multi-character consistent storytelling. Current approaches based on static diffusion models, whether used in a one-shot manner or within multi-agent frameworks, face three key limitations: (1) Static models lack dynamic expressiveness and often resort to "copy-paste" pattern. (2) One-shot inference cannot iteratively correct missing attributes or poor prompt adherence. (3) Multi-agents rely on non-robust evaluators, ill-suited for assessing stylized, non-realistic animation. To address these, we propose AnimeAgent, the first Image-to-Video (I2V)-based multi-agent framework for CSG. Inspired by Disney's "Combination of Straight Ahead and Pose to Pose" workflow, AnimeAgent leverages I2V's implicit motion prior to enhance consistency and expressiveness, while a mixed subjective-objective reviewer enables reliable iterative refinement. We also collect a human-annotated CSG benchmark with ground-truth. Experiments show AnimeAgent achieves SOTA performance in consistency, prompt fidelity, and stylization.

自定义故事板生成 (CSG) 旨在制作高质量、多角色一致的故事讲述。当前基于静态扩散模型的方法，无论是一次性使用还是在多智能体框架内使用，都面临三个关键限制：（1）静态模型缺乏动态表达能力，并且经常采用“复制粘贴”模式。 (2) 一次性推理无法迭代地纠正缺失的属性或提示依从性差。 (3) 多智能体依赖于非鲁棒评估器，不适合评估风格化、非现实的动画。为了解决这些问题，我们提出了 AnimeAgent，这是第一个基于图像到视频 (I2V) 的 CSG 多代理框架。受迪士尼“直线前进和姿势到姿势的组合”工作流程的启发，AnimeAgent 在增强一致性和表现力之前利用 I2V 的隐式运动，而混合主客观审阅器可实现可靠的迭代细化。我们还收集了具有真实性的人工注释 CSG 基准。实验表明 AnimeAgent 在一致性、提示保真度和风格化方面实现了 SOTA 性能。

</details>

---

## 18. LESA: Learnable Stage-Aware Predictors for Diffusion Model Acceleration / LESA：用于扩散模型加速的可学习阶段感知预测器

**Date**: 2026-02-24 | **arXiv**: [2602.20497v1](http://arxiv.org/abs/2602.20497v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.20497v1)

**Categories**: cs.CV, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Diffusion models have achieved remarkable success in image and video generation tasks. However, the high computational demands of Diffusion Transformers (DiTs) pose a significant challenge to their practical deployment. While feature caching is a promising acceleration strategy, existing methods based on simple reusing or training-free forecasting struggle to adapt to the complex, stage-dependent dynamics of the diffusion process, often resulting in quality degradation and failing to maintain consistency with the standard denoising process. To address this, we propose a LEarnable Stage-Aware (LESA) predictor framework based on two-stage training. Our approach leverages a Kolmogorov-Arnold Network (KAN) to accurately learn temporal feature mappings from data. We further introduce a multi-stage, multi-expert architecture that assigns specialized predictors to different noise-level stages, enabling more precise and robust feature forecasting. Extensive experiments show our method achieves significant acceleration while maintaining high-fidelity generation. Experiments demonstrate 5.00x acceleration on FLUX.1-dev with minimal quality degradation (1.0% drop), 6.25x speedup on Qwen-Image with a 20.2% quality improvement over the previous SOTA (TaylorSeer), and 5.00x acceleration on HunyuanVideo with a 24.7% PSNR improvement over TaylorSeer. State-of-the-art performance on both text-to-image and text-to-video synthesis validates the effectiveness and generalization capability of our training-based framework across different models. Our code is included in the supplementary materials and will be released on GitHub.

扩散模型在图像和视频生成任务中取得了显着的成功。然而，扩散变压器（DiT）的高计算要求对其实际部署提出了重大挑战。虽然特征缓存是一种很有前途的加速策略，但基于简单重用或免训练预测的现有方法很难适应扩散过程的复杂、阶段相关的动态，通常会导致质量下降，并且无法保持与标准去噪过程的一致性。为了解决这个问题，我们提出了一个基于两阶段训练的 LEarnable Stage-Aware (LESA) 预测器框架。我们的方法利用柯尔莫哥洛夫-阿诺德网络（KAN）来准确地从数据中学习时间特征映射。我们进一步引入了多阶段、多专家架构，将专门的预测器分配给不同的噪声级别阶段，从而实现更精确和稳健的特征预测。大量的实验表明，我们的方法在保持高保真生成的同时实现了显着的加速。实验表明，FLUX.1-dev 上的加速为 5.00 倍，质量下降最小（下降 1.0%）；Qwen-Image 上的加速为 6.25 倍，与之前的 SOTA（TaylorSeer）相比，质量提高了 20.2%；HunyuanVideo 上的加速为 5.00 倍，PSNR 比 TaylorSeer 提高了 24.7%。文本到图像和文本到视频合成的最先进性能验证了我们基于训练的框架在不同模型上的有效性和泛化能力。我们的代码包含在补充材料中，并将在 GitHub 上发布。

</details>

---

## 19. NovaPlan: Zero-Shot Long-Horizon Manipulation via Closed-Loop Video Language Planning / NovaPlan：通过闭环视频语言规划进行零射击长视野操作

**Date**: 2026-02-23 | **arXiv**: [2602.20119v1](http://arxiv.org/abs/2602.20119v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.20119v1)

**Categories**: cs.RO, cs.AI, cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Solving long-horizon tasks requires robots to integrate high-level semantic reasoning with low-level physical interaction. While vision-language models (VLMs) and video generation models can decompose tasks and imagine outcomes, they often lack the physical grounding necessary for real-world execution. We introduce NovaPlan, a hierarchical framework that unifies closed-loop VLM and video planning with geometrically grounded robot execution for zero-shot long-horizon manipulation. At the high level, a VLM planner decomposes tasks into sub-goals and monitors robot execution in a closed loop, enabling the system to recover from single-step failures through autonomous re-planning. To compute low-level robot actions, we extract and utilize both task-relevant object keypoints and human hand poses as kinematic priors from the generated videos, and employ a switching mechanism to choose the better one as a reference for robot actions, maintaining stable execution even under heavy occlusion or depth inaccuracy. We demonstrate the effectiveness of NovaPlan on three long-horizon tasks and the Functional Manipulation Benchmark (FMB). Our results show that NovaPlan can perform complex assembly tasks and exhibit dexterous error recovery behaviors without any prior demonstrations or training. Project page: https://nova-plan.github.io/

解决长期任务需要机器人将高级语义推理与低级物理交互相结合。虽然视觉语言模型 (VLM) 和视频生成模型可以分解任务并想象结果，但它们通常缺乏现实世界执行所需的物理基础。我们引入了 NovaPlan，这是一个分层框架，它将闭环 VLM 和视频规划与几何接地机器人执行相结合，以实现零样本长视野操作。在高层，VLM 规划器将任务分解为子目标，并在闭环中监控机器人的执行情况，使系统能够通过自主重新规划从单步故障中恢复。为了计算低级机器人动作，我们从生成的视频中提取并利用与任务相关的对象关键点和人手姿势作为运动学先验，并采用切换机制来选择更好的动作作为机器人动作的参考，即使在严重遮挡或深度不准确的情况下也能保持稳定的执行。我们展示了 NovaPlan 在三项长期任务和功能操作基准（FMB）上的有效性。我们的结果表明，NovaPlan 可以执行复杂的组装任务并表现出灵巧的错误恢复行为，而无需任何事先演示或培训。项目页面：https://nova-plan.github.io/

</details>

---



</details>

<details><summary><b>2026-02-24 (1 papers)</b></summary>

# arXiv World Model Papers - 2026-02-24

**Paper Count**: 1

---

## 1. K-Search: LLM Kernel Generation via Co-Evolving Intrinsic World Model / K-Search：通过共同进化的内在世界模型生成 LLM 内核

**Date**: 2026-02-22 | **arXiv**: [2602.19128v1](http://arxiv.org/abs/2602.19128v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.19128v1)

**Categories**: cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Optimizing GPU kernels is critical for efficient modern machine learning systems yet remains challenging due to the complex interplay of design factors and rapid hardware evolution. Existing automated approaches typically treat Large Language Models (LLMs) merely as stochastic code generators within heuristic-guided evolutionary loops. These methods often struggle with complex kernels requiring coordinated, multi-step structural transformations, as they lack explicit planning capabilities and frequently discard promising strategies due to inefficient or incorrect intermediate implementations. To address this, we propose Search via Co-Evolving World Model and build K-Search based on this method. By replacing static search heuristics with a co-evolving world model, our framework leverages LLMs' prior domain knowledge to guide the search, actively exploring the optimization space. This approach explicitly decouples high-level algorithmic planning from low-level program instantiation, enabling the system to navigate non-monotonic optimization paths while remaining resilient to temporary implementation defects. We evaluate K-Search on diverse, complex kernels from FlashInfer, including GQA, MLA, and MoE kernels. Our results show that K-Search significantly outperforms state-of-the-art evolutionary search methods, achieving an average 2.10x improvement and up to a 14.3x gain on complex MoE kernels. On the GPUMode TriMul task, K-Search achieves state-of-the-art performance on H100, reaching 1030us and surpassing both prior evolution and human-designed solutions.

优化 GPU 内核对于高效的现代机器学习系统至关重要，但由于设计因素和快速硬件发展的复杂相互作用，仍然具有挑战性。现有的自动化方法通常仅将大型语言模型（LLM）视为启发式引导的进化循环中的随机代码生成器。这些方法经常与需要协调、多步结构转换的复杂内核作斗争，因为它们缺乏明确的规划能力，并且经常由于低效或不正确的中间实现而放弃有希望的策略。为了解决这个问题，我们提出通过共同进化世界模型进行搜索，并基于该方法构建 K-Search。通过用共同进化的世界模型取代静态搜索启发式，我们的框架利用法学硕士的先验领域知识来指导搜索，积极探索优化空间。这种方法明确地将高级算法规划与低级程序实例化解耦，使系统能够导航非单调优化路径，同时保持对临时实现缺陷的弹性。我们在 FlashInfer 的各种复杂内核上评估 K-Search，包括 GQA、MLA 和 MoE 内核。我们的结果表明，K-Search 的性能显着优于最先进的进化搜索方法，在复杂的 MoE 内核上实现了平均 2.10 倍的改进和高达 14.3 倍的增益。在 GPUMode TriMul 任务中，K-Search 在 H100 上实现了最先进的性能，达到 1030us，超越了先前的进化和人类设计的解决方案。

</details>

---



</details>

<details><summary><b>2026-02-20 (2 papers)</b></summary>

# arXiv World Model Papers - 2026-02-20

**Paper Count**: 2

---

## 1. AI Gamestore: Scalable, Open-Ended Evaluation of Machine General Intelligence with Human Games / AI Gamestore：通过人类游戏对机器通用智能进行可扩展、开放式评估

**Date**: 2026-02-19 | **arXiv**: [2602.17594v1](http://arxiv.org/abs/2602.17594v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.17594v1)

**Categories**: cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Rigorously evaluating machine intelligence against the broad spectrum of human general intelligence has become increasingly important and challenging in this era of rapid technological advance. Conventional AI benchmarks typically assess only narrow capabilities in a limited range of human activity. Most are also static, quickly saturating as developers explicitly or implicitly optimize for them. We propose that a more promising way to evaluate human-like general intelligence in AI systems is through a particularly strong form of general game playing: studying how and how well they play and learn to play \textbf{all conceivable human games}, in comparison to human players with the same level of experience, time, or other resources. We define a "human game" to be a game designed by humans for humans, and argue for the evaluative suitability of this space of all such games people can imagine and enjoy -- the "Multiverse of Human Games". Taking a first step towards this vision, we introduce the AI GameStore, a scalable and open-ended platform that uses LLMs with humans-in-the-loop to synthesize new representative human games, by automatically sourcing and adapting standardized and containerized variants of game environments from popular human digital gaming platforms. As a proof of concept, we generated 100 such games based on the top charts of Apple App Store and Steam, and evaluated seven frontier vision-language models (VLMs) on short episodes of play. The best models achieved less than 10\% of the human average score on the majority of the games, and especially struggled with games that challenge world-model learning, memory and planning. We conclude with a set of next steps for building out the AI GameStore as a practical way to measure and drive progress toward human-like general intelligence in machines.

在这个技术快速进步的时代，根据广泛的人类通用智能严格评估机器智能变得越来越重要和具有挑战性。传统的人工智能基准通常仅评估有限范围的人类活动中的狭窄能力。大多数也是静态的，随着开发人员显式或隐式地优化它们，它们很快就会饱和。我们提出，评估人工智能系统中类人通用智能的一种更有前景的方法是通过一种特别强大的通用游戏玩法：与具有相同经验、时间或其他资源水平的人类玩家相比，研究它们如何玩、玩得如何以及学会玩\textbf{所有可以想象的人类游戏}。我们将“人类游戏”定义为由人类为人类设计的游戏，并论证了人们可以想象和享受的所有此类游戏空间的评估适用性——“人类游戏的多元宇宙”。为了实现这一愿景，我们迈出了第一步，我们推出了 AI GameStore，这是一个可扩展的开放式平台，它使用法学硕士和人类在环技术，通过自动从流行的人类数字游戏平台中获取和调整游戏环境的标准化和容器化变体，来合成新的代表性人类游戏。作为概念验证，我们根据 Apple App Store 和 Steam 的热门排行榜生成了 100 款此类游戏，并在短集游戏中评估了 7 个前沿视觉语言模型 (VLM)。最好的模型在大多数游戏中的得分都不到人类平均得分的 10%，尤其是在挑战世界模型学习、记忆和规划的游戏中表现不佳。最后，我们提出了一系列后续步骤，旨在构建 AI GameStore，作为衡量和推动机器类人通用智能进步的实用方法。

</details>

---

## 2. Continual learning and refinement of causal models through dynamic predicate invention / 通过动态谓词发明不断学习和完善因果模型

**Date**: 2026-02-19 | **arXiv**: [2602.17217v1](http://arxiv.org/abs/2602.17217v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.17217v1)

**Categories**: cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Efficiently navigating complex environments requires agents to internalize the underlying logic of their world, yet standard world modelling methods often struggle with sample inefficiency, lack of transparency, and poor scalability. We propose a framework for constructing symbolic causal world models entirely online by integrating continuous model learning and repair into the agent's decision loop, by leveraging the power of Meta-Interpretive Learning and predicate invention to find semantically meaningful and reusable abstractions, allowing an agent to construct a hierarchy of disentangled, high-quality concepts from its observations. We demonstrate that our lifted inference approach scales to domains with complex relational dynamics, where propositional methods suffer from combinatorial explosion, while achieving sample-efficiency orders of magnitude higher than the established PPO neural-network-based baseline.

有效地驾驭复杂的环境需要智能体将其世界的底层逻辑内化，但标准的世界建模方法常常面临样本效率低、缺乏透明度和可扩展性差的问题。我们提出了一个完全在线构建符号因果世界模型的框架，通过将连续模型学习和修复集成到代理的决策循环中，利用元解释学习和谓词发明的力量来找到语义上有意义和可重用的抽象，从而允许代理从其观察中构建一个解开的高质量概念的层次结构。我们证明，我们的提升推理方法可以扩展到具有复杂关系动态的领域，其中命题方法遭受组合爆炸，同时实现的样本效率数量级高于已建立的基于 PPO 神经网络的基线。

</details>

---



</details>

<details><summary><b>2026-02-19 (4 papers)</b></summary>

# arXiv World Model Papers - 2026-02-19

**Paper Count**: 4

---

## 1. Factored Latent Action World Models / 分解的潜在动作世界模型

**Date**: 2026-02-18 | **arXiv**: [2602.16229v1](http://arxiv.org/abs/2602.16229v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.16229v1)

**Categories**: cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Learning latent actions from action-free video has emerged as a powerful paradigm for scaling up controllable world model learning. Latent actions provide a natural interface for users to iteratively generate and manipulate videos. However, most existing approaches rely on monolithic inverse and forward dynamics models that learn a single latent action to control the entire scene, and therefore struggle in complex environments where multiple entities act simultaneously. This paper introduces Factored Latent Action Model (FLAM), a factored dynamics framework that decomposes the scene into independent factors, each inferring its own latent action and predicting its own next-step factor value. This factorized structure enables more accurate modeling of complex multi-entity dynamics and improves video generation quality in action-free video settings compared to monolithic models. Based on experiments on both simulation and real-world multi-entity datasets, we find that FLAM outperforms prior work in prediction accuracy and representation quality, and facilitates downstream policy learning, demonstrating the benefits of factorized latent action models.

从无动作视频中学习潜在动作已成为扩大可控世界模型学习的强大范例。潜在动作为用户迭代生成和操作视频提供了一个自然的界面。然而，大多数现有方法依赖于整体逆向和正向动力学模型，这些模型学习单个潜在动作来控制整个场景，因此在多个实体同时动作的复杂环境中陷入困境。本文介绍了因子式潜在动作模型（FLAM），这是一种因子式动力学框架，它将场景分解为独立的因素，每个因子都推断自己的潜在动作并预测自己的下一步因子值。与整体模型相比，这种分解结构可以更准确地对复杂的多实体动态进行建模，并提高无动作视频设置中的视频生成质量。基于模拟和现实世界多实体数据集的实验，我们发现 FLAM 在预测精度和表示质量方面优于先前的工作，并促进下游策略学习，展示了因子化潜在动作模型的好处。

</details>

---

## 2. Learning to unfold cloth: Scaling up world models to deformable object manipulation / 学习展开布料：将世界模型扩展到可变形对象操作

**Date**: 2026-02-18 | **arXiv**: [2602.16675v1](http://arxiv.org/abs/2602.16675v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.16675v1)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Learning to manipulate cloth is both a paradigmatic problem for robotic research and a problem of immediate relevance to a variety of applications ranging from assistive care to the service industry. The complex physics of the deformable object makes this problem of cloth manipulation nontrivial. In order to create a general manipulation strategy that addresses a variety of shapes, sizes, fold and wrinkle patterns, in addition to the usual problems of appearance variations, it becomes important to carefully consider model structure and their implications for generalisation performance. In this paper, we present an approach to in-air cloth manipulation that uses a variation of a recently proposed reinforcement learning architecture, DreamerV2. Our implementation modifies this architecture to utilise surface normals input, in addition to modiying the replay buffer and data augmentation procedures. Taken together these modifications represent an enhancement to the world model used by the robot, addressing the physical complexity of the object being manipulated by the robot. We present evaluations both in simulation and in a zero-shot deployment of the trained policies in a physical robot setup, performing in-air unfolding of a variety of different cloth types, demonstrating the generalisation benefits of our proposed architecture.

学习操纵布料既是机器人研究的一个典型问题，也是一个与从辅助护理到服务行业的各种应用直接相关的问题。可变形物体的复杂物理特性使得布料操纵的问题变得非常重要。为了创建解决各种形状、尺寸、折叠和皱纹图案的通用操作策略，除了外观变化的常见问题之外，仔细考虑模型结构及其对泛化性能的影响也变得很重要。在本文中，我们提出了一种空中布料操纵方法，该方法使用最近提出的强化学习架构 DreamerV2 的变体。除了修改重播缓冲区和数据增强程序之外，我们的实现还修改了该架构以利用表面法线输入。总的来说，这些修改代表了对机器人使用的世界模型的增强，解决了机器人操纵的物体的物理复杂性。我们在物理机器人设置中对经过训练的策略进行模拟和零次部署，执行各种不同布料类型的空中展开，展示了我们提出的架构的泛化优势。

</details>

---

## 3. World Model Failure Classification and Anomaly Detection for Autonomous Inspection / 用于自主检查的世界模型故障分类和异常检测

**Date**: 2026-02-18 | **arXiv**: [2602.16182v1](http://arxiv.org/abs/2602.16182v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.16182v1)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Autonomous inspection robots for monitoring industrial sites can reduce costs and risks associated with human-led inspection. However, accurate readings can be challenging due to occlusions, limited viewpoints, or unexpected environmental conditions. We propose a hybrid framework that combines supervised failure classification with anomaly detection, enabling classification of inspection tasks as a success, known failure, or anomaly (i.e., out-of-distribution) case. Our approach uses a world model backbone with compressed video inputs. This policy-agnostic, distribution-free framework determines classifications based on two decision functions set by conformal prediction (CP) thresholds before a human observer does. We evaluate the framework on gauge inspection feeds collected from office and industrial sites and demonstrate real-time deployment on a Boston Dynamics Spot. Experiments show over 90% accuracy in distinguishing between successes, failures, and OOD cases, with classifications occurring earlier than a human observer. These results highlight the potential for robust, anticipatory failure detection in autonomous inspection tasks or as a feedback signal for model training to assess and improve the quality of training data. Project website: https://autoinspection-classification.github.io

用于监控工业现场的自主检查机器人可以降低与人工检查相关的成本和风险。然而，由于遮挡、有限的视角或意外的环境条件，准确的读数可能具有挑战性。我们提出了一种混合框架，将监督故障分类与异常检测相结合，从而能够将检查任务分类为成功、已知故障或异常（即分布外）情况。我们的方法使用具有压缩视频输入的世界模型主干。这种与策略无关、与分布无关的框架先于人类观察者根据由共形预测 (CP) 阈值设置的两个决策函数来确定分类。我们评估从办公室和工业场所收集的仪表检查源的框架，并在 Boston Dynamics Spot 上演示实时部署。实验表明，区分成功、失败和 OOD 案例的准确率超过 90%，并且分类发生得比人类观察者更早。这些结果凸显了在自主检查任务中进行稳健的预期故障检测或作为模型训练的反馈信号以评估和提高训练数据质量的潜力。项目网站：https://autoinspection-classification.github.io

</details>

---

## 4. ODYN: An All-Shifted Non-Interior-Point Method for Quadratic Programming in Robotics and AI / ODYN：机器人和人工智能二次规划的全平移非内点方法

**Date**: 2026-02-17 | **arXiv**: [2602.16005v1](http://arxiv.org/abs/2602.16005v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.16005v1)

**Categories**: cs.RO, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

We introduce ODYN, a novel all-shifted primal-dual non-interior-point quadratic programming (QP) solver designed to efficiently handle challenging dense and sparse QPs. ODYN combines all-shifted nonlinear complementarity problem (NCP) functions with proximal method of multipliers to robustly address ill-conditioned and degenerate problems, without requiring linear independence of the constraints. It exhibits strong warm-start performance and is well suited to both general-purpose optimization, and robotics and AI applications, including model-based control, estimation, and kernel-based learning methods. We provide an open-source implementation and benchmark ODYN on the Maros-Mészáros test set, demonstrating state-of-the-art convergence performance in small-to-high-scale problems. The results highlight ODYN's superior warm-starting capabilities, which are critical in sequential and real-time settings common in robotics and AI. These advantages are further demonstrated by deploying ODYN as the backend of an SQP-based predictive control framework (OdynSQP), as the implicitly differentiable optimization layer for deep learning (ODYNLayer), and the optimizer of a contact-dynamics simulation (ODYNSim).

我们推出 ODYN，这是一种新颖的全平移原对偶非内点二次规划 (QP) 求解器，旨在有效处理具有挑战性的密集和稀疏 QP。 ODYN 将全移位非线性互补问题 (NCP) 函数与乘法器的近端方法相结合，以稳健地解决病态和退化问题，而不需要约束的线性独立性。它具有强大的热启动性能，非常适合通用优化以及机器人和人工智能应用，包括基于模型的控制、估计和基于内核的学习方法。我们在 Maros-Mészáros 测试集上提供开源实现和基准 ODYN，展示了小规模到大规模问题中最先进的收敛性能。结果凸显了 ODYN 卓越的热启动能力，这对于机器人和人工智能中常见的顺序和实时设置至关重要。通过将 ODYN 部署为基于 SQP 的预测控制框架 (OdynSQP) 的后端、深度学习的隐式可微优化层 (ODYNLayer) 以及接触动力学模拟的优化器 (ODYNSim)，进一步证明了这些优势。

</details>

---



</details>

<details><summary><b>2026-02-18 (6 papers)</b></summary>

# arXiv World Model Papers - 2026-02-18

**Paper Count**: 6

---

## 1. VLM-DEWM: Dynamic External World Model for Verifiable and Resilient Vision-Language Planning in Manufacturing / VLM-DEWM：用于制造中可验证和弹性视觉语言规划的动态外部世界模型

**Date**: 2026-02-17 | **arXiv**: [2602.15549v1](http://arxiv.org/abs/2602.15549v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.15549v1)

**Categories**: cs.RO, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Vision-language model (VLM) shows promise for high-level planning in smart manufacturing, yet their deployment in dynamic workcells faces two critical challenges: (1) stateless operation, they cannot persistently track out-of-view states, causing world-state drift; and (2) opaque reasoning, failures are difficult to diagnose, leading to costly blind retries. This paper presents VLM-DEWM, a cognitive architecture that decouples VLM reasoning from world-state management through a persistent, queryable Dynamic External World Model (DEWM). Each VLM decision is structured into an Externalizable Reasoning Trace (ERT), comprising action proposal, world belief, and causal assumption, which is validated against DEWM before execution. When failures occur, discrepancy analysis between predicted and observed states enables targeted recovery instead of global replanning. We evaluate VLM-DEWM on multi-station assembly, large-scale facility exploration, and real-robot recovery under induced failures. Compared to baseline memory-augmented VLM systems, VLM DEWM improves state-tracking accuracy from 56% to 93%, increases recovery success rate from below 5% to 95%, and significantly reduces computational overhead through structured memory. These results establish VLM-DEWM as a verifiable and resilient solution for long-horizon robotic operations in dynamic manufacturing environments.

视觉语言模型（VLM）显示了智能制造中高层规划的前景，但它们在动态工作单元中的部署面临着两个关键挑战：（1）无状态操作，它们无法持续跟踪视野外的状态，导致世界状态漂移； (2) 推理不透明，故障难以诊断，导致盲目重试成本高昂。本文提出了 VLM-DEWM，这是一种认知架构，通过持久的、可查询的动态外部世界模型 (DEWM) 将 VLM 推理与世界状态管理解耦。每个 VLM 决策都被构建为外部化推理跟踪 (ERT)，其中包括行动建议、世界信念和因果假设，并在执行前针对 DEWM 进行验证。当发生故障时，预测状态和观察状态之间的差异分析可以实现有针对性的恢复，而不是全局重新规划。我们评估了 VLM-DEWM 的多站装配、大规模设施探索以及诱发故障下的真实机器人恢复。与基线内存增强 VLM 系统相比，VLM DEWM 将状态跟踪精度从 56% 提高到 93%，将恢复成功率从 5% 以下提高到 95%，并通过结构化内存显着降低计算开销。这些结果使 VLM-DEWM 成为动态制造环境中长期机器人操作的可验证且有弹性的解决方案。

</details>

---

## 2. World-Model-Augmented Web Agents with Action Correction / 具有动作校正功能的世界模型增强网络代理

**Date**: 2026-02-17 | **arXiv**: [2602.15384v1](http://arxiv.org/abs/2602.15384v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.15384v1)

**Categories**: cs.AI, cs.CL

<details><summary><b>Abstract / 摘要</b></summary>

Web agents based on large language models have demonstrated promising capability in automating web tasks. However, current web agents struggle to reason out sensible actions due to the limitations of predicting environment changes, and might not possess comprehensive awareness of execution risks, prematurely performing risky actions that cause losses and lead to task failure. To address these challenges, we propose WAC, a web agent that integrates model collaboration, consequence simulation, and feedback-driven action refinement. To overcome the cognitive isolation of individual models, we introduce a multi-agent collaboration process that enables an action model to consult a world model as a web-environment expert for strategic guidance; the action model then grounds these suggestions into executable actions, leveraging prior knowledge of environmental state transition dynamics to enhance candidate action proposal. To achieve risk-aware resilient task execution, we introduce a two-stage deduction chain. A world model, specialized in environmental state transitions, simulates action outcomes, which a judge model then scrutinizes to trigger action corrective feedback when necessary. Experiments show that WAC achieves absolute gains of 1.8% on VisualWebArena and 1.3% on Online-Mind2Web.

基于大型语言模型的 Web 代理在自动化 Web 任务方面表现出了良好的能力。然而，当前的网络代理由于预测环境变化的局限性，难以推理出合理的行动，并且可能不具备全面的执行风险意识，过早地执行风险行动，造成损失并导致任务失败。为了应对这些挑战，我们提出了 WAC，这是一种集成了模型协作、结果模拟和反馈驱动的动作细化的网络代理。为了克服各个模型的认知隔离，我们引入了多智能体协作流程，使行动模型能够作为网络环境专家咨询世界模型以获取战略指导；然后，行动模型将这些建议转化为可执行的行动，利用环境状态转换动态的先验知识来增强候选行动建议。为了实现风险感知的弹性任务执行，我们引入了两阶段推论链。专门研究环境状态转换的世界模型会模拟行动结果，然后法官模型会对其进行仔细检查，以在必要时触发行动纠正反馈。实验表明，WAC 在 VisualWebArena 上获得了 1.8% 的绝对收益，在 Online-Mind2Web 上获得了 1.3% 的绝对收益。

</details>

---

## 3. Feasibility-aware Imitation Learning from Observation with Multimodal Feedback / 通过多模态反馈进行观察的可行性感知模仿学习

**Date**: 2026-02-17 | **arXiv**: [2602.15351v1](http://arxiv.org/abs/2602.15351v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.15351v1)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Imitation learning frameworks that learn robot control policies from demonstrators' motions via hand-mounted demonstration interfaces have attracted increasing attention. However, due to differences in physical characteristics between demonstrators and robots, this approach faces two limitations: i) the demonstration data do not include robot actions, and ii) the demonstrated motions may be infeasible for robots. These limitations make policy learning difficult. To address them, we propose Feasibility-Aware Behavior Cloning from Observation (FABCO). FABCO integrates behavior cloning from observation, which complements robot actions using robot dynamics models, with feasibility estimation. In feasibility estimation, the demonstrated motions are evaluated using a robot-dynamics model, learned from the robot's execution data, to assess reproducibility under the robot's dynamics. The estimated feasibility is used for multimodal feedback and feasibility-aware policy learning to improve the demonstrator's motions and learn robust policies. Multimodal feedback provides feasibility through the demonstrator's visual and haptic senses to promote feasible demonstrated motions. Feasibility-aware policy learning reduces the influence of demonstrated motions that are infeasible for robots, enabling the learning of policies that robots can execute stably. We conducted experiments with 15 participants on two tasks and confirmed that FABCO improves imitation learning performance by more than 3.2 times compared to the case without feasibility feedback.

通过手持式演示界面从演示者的动作中学习机器人控制策略的模仿学习框架引起了越来越多的关注。然而，由于演示者和机器人之间的物理特征差异，这种方法面临两个限制：i）演示数据不包括机器人动作，ii）演示的运动对于机器人来说可能不可行。这些限制使得政策学习变得困难。为了解决这些问题，我们提出了基于观察的可行性感知行为克隆（FABCO）。 FABCO 将观察行为克隆与可行性评估相结合，利用机器人动力学模型补充机器人动作。在可行性评估中，使用从机器人的执行数据中学习的机器人动力学模型来评估演示的运动，以评估机器人动力学下的再现性。估计的可行性用于多模式反馈和可行性感知政策学习，以改进演示者的动作并学习稳健的政策。多模态反馈通过演示者的视觉和触觉提供可行性，以促进可行的演示动作。可行性感知策略学习减少了机器人无法执行的演示动作的影响，从而能够学习机器人可以稳定执行的策略。我们对 15 名参与者进行了两项任务的实验，证实 FABCO 与没有可行性反馈的情况相比，模仿学习性能提高了 3.2 倍以上。

</details>

---

## 4. Cold-Start Personalization via Training-Free Priors from Structured World Models / 通过结构化世界模型的免训练先验进行冷启动个性化

**Date**: 2026-02-16 | **arXiv**: [2602.15012v1](http://arxiv.org/abs/2602.15012v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.15012v1)

**Categories**: cs.CL, cs.AI, cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

Cold-start personalization requires inferring user preferences through interaction when no user-specific historical data is available. The core challenge is a routing problem: each task admits dozens of preference dimensions, yet individual users care about only a few, and which ones matter depends on who is asking. With a limited question budget, asking without structure will miss the dimensions that matter. Reinforcement learning is the natural formulation, but in multi-turn settings its terminal reward fails to exploit the factored, per-criterion structure of preference data, and in practice learned policies collapse to static question sequences that ignore user responses. We propose decomposing cold-start elicitation into offline structure learning and online Bayesian inference. Pep (Preference Elicitation with Priors) learns a structured world model of preference correlations offline from complete profiles, then performs training-free Bayesian inference online to select informative questions and predict complete preference profiles, including dimensions never asked about. The framework is modular across downstream solvers and requires only simple belief models. Across medical, mathematical, social, and commonsense reasoning, Pep achieves 80.8% alignment between generated responses and users' stated preferences versus 68.5% for RL, with 3-5x fewer interactions. When two users give different answers to the same question, Pep changes its follow-up 39-62% of the time versus 0-28% for RL. It does so with ~10K parameters versus 8B for RL, showing that the bottleneck in cold-start elicitation is the capability to exploit the factored structure of preference data.

冷启动个性化需要在没有特定于用户的历史数据可用时通过交互推断用户偏好。核心挑战是路由问题：每个任务都有数十个偏好维度，但个人用户只关心其中几个，而哪些维度重要取决于提出请求的人。由于问题预算有限，没有结构的提问会错过重要的维度。强化学习是自然的公式，但在多轮设置中，其最终奖励无法利用偏好数据的分解的、按标准的结构，并且在实践中学习的策略崩溃为忽略用户响应的静态问题序列。我们建议将冷启动启发分解为离线结构学习和在线贝叶斯推理。 Pep（先验偏好启发）从完整的配置文件中离线学习偏好相关性的结构化世界模型，然后在线执行免训练贝叶斯推理以选择信息性问题并预测完整的偏好配置文件，包括从未询问过的维度。该框架在下游求解器中是模块化的，并且只需要简单的信念模型。在医学、数学、社会和常识推理方面，Pep 在生成的响应和用户陈述的偏好之间实现了 80.8% 的一致性，而 RL 的一致性为 68.5%，交互次数减少了 3-5 倍。当两个用户对同一问题给出不同答案时，Pep 在 39-62% 的情况下会更改其后续内容，而 RL 的这一比例为 0-28%。与 RL 的 8B 参数相比，它使用约 10K 参数来实现这一点，这表明冷启动启发的瓶颈是利用偏好数据的分解结构的能力。

</details>

---

## 5. World Models for Policy Refinement in StarCraft II / 星际争霸 II 中政策细化的世界模型

**Date**: 2026-02-16 | **arXiv**: [2602.14857v1](http://arxiv.org/abs/2602.14857v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.14857v1)

**Categories**: cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Large Language Models (LLMs) have recently shown strong reasoning and generalization capabilities, motivating their use as decision-making policies in complex environments. StarCraft II (SC2), with its massive state-action space and partial observability, is a challenging testbed. However, existing LLM-based SC2 agents primarily focus on improving the policy itself and overlook integrating a learnable, action-conditioned transition model into the decision loop. To bridge this gap, we propose StarWM, the first world model for SC2 that predicts future observations under partial observability. To facilitate learning SC2's hybrid dynamics, we introduce a structured textual representation that factorizes observations into five semantic modules, and construct SC2-Dynamics-50k, the first instruction-tuning dataset for SC2 dynamics prediction. We further develop a multi-dimensional offline evaluation framework for predicted structured observations. Offline results show StarWM's substantial gains over zero-shot baselines, including nearly 60% improvements in resource prediction accuracy and self-side macro-situation consistency. Finally, we propose StarWM-Agent, a world-model-augmented decision system that integrates StarWM into a Generate--Simulate--Refine decision loop for foresight-driven policy refinement. Online evaluation against SC2's built-in AI demonstrates consistent improvements, yielding win-rate gains of 30%, 15%, and 30% against Hard (LV5), Harder (LV6), and VeryHard (LV7), respectively, alongside improved macro-management stability and tactical risk assessment.

大型语言模型（LLM）最近表现出强大的推理和泛化能力，促使它们在复杂环境中用作决策策略。星际争霸 II (SC2) 具有巨大的状态动作空间和部分可观测性，是一个具有挑战性的测试平台。然而，现有的基于 LLM 的 SC2 智能体主要侧重于改进策略本身，而忽略了将可学习的、以行动为条件的转换模型集成到决策循环中。为了弥补这一差距，我们提出了 StarWM，这是 SC2 的第一个世界模型，可以在部分可观测性下预测未来的观测结果。为了促进学习 SC2 的混合动力学，我们引入了一种结构化文本表示，将观察结果分解为五个语义模块，并构建了 SC2-Dynamics-50k，这是第一个用于 SC2 动力学预测的指令调整数据集。我们进一步开发了一个用于预测结构化观察的多维离线评估框架。离线结果显示，StarWM 较零样本基线有大幅提升，包括资源预测精度和自身宏观情况一致性方面提高了近 60%。最后，我们提出了 StarWM-Agent，这是一个世界模型增强决策系统，它将 StarWM 集成到生成-模拟-细化决策循环中，以实现前瞻驱动的政策细化。针对 SC2 内置 AI 的在线评估显示出持续的改进，相对于 Hard (LV5)、Harder (LV6) 和 VeryHard (LV7) 胜率分别提高了 30%、15% 和 30%，同时改善了宏观管理稳定性和战术风险评估。

</details>

---

## 6. WebWorld: A Large-Scale World Model for Web Agent Training / WebWorld：用于 Web 代理训练的大规模世界模型

**Date**: 2026-02-16 | **arXiv**: [2602.14721v1](http://arxiv.org/abs/2602.14721v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.14721v1)

**Categories**: cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Web agents require massive trajectories to generalize, yet real-world training is constrained by network latency, rate limits, and safety risks. We introduce \textbf{WebWorld} series, the first open-web simulator trained at scale. While existing simulators are restricted to closed environments with thousands of trajectories, WebWorld leverages a scalable data pipeline to train on 1M+ open-web interactions, supporting reasoning, multi-format data, and long-horizon simulations of 30+ steps. For intrinsic evaluation, we introduce WebWorld-Bench with dual metrics spanning nine dimensions, where WebWorld achieves simulation performance comparable to Gemini-3-Pro. For extrinsic evaluation, Qwen3-14B trained on WebWorld-synthesized trajectories improves by +9.2\% on WebArena, reaching performance comparable to GPT-4o. WebWorld enables effective inference-time search, outperforming GPT-5 as a world model. Beyond web simulation, WebWorld exhibits cross-domain generalization to code, GUI, and game environments, providing a replicable recipe for world model construction.

网络代理需要大量的轨迹来进行概括，但现实世界的训练受到网络延迟、速率限制和安全风险的限制。我们推出 \textbf{WebWorld} 系列，这是第一个大规模训练的开放网络模拟器。虽然现有模拟器仅限于具有数千条轨迹的封闭环境，但 WebWorld 利用可扩展的数据管道来训练超过 100 万次开放网络交互，支持推理、多格式数据和 30 多个步骤的长期模拟。对于内在评估，我们引入了具有跨越九个维度的双指标的WebWorld-Bench，其中WebWorld实现了与Gemini-3-Pro相当的模拟性能。对于外部评估，在 WebWorld 合成轨迹上训练的 Qwen3-14B 在 WebArena 上提高了 +9.2%，达到了与 GPT-4o 相当的性能。 WebWorld 可实现有效的推理时间搜索，作为世界模型，其性能优于 GPT-5。除了网络模拟之外，WebWorld 还展示了对代码、GUI 和游戏环境的跨域泛化，为世界模型构建提供了可复制的方法。

</details>

---



</details>

<details><summary><b>2026-02-17 (1 papers)</b></summary>

# arXiv World Model Papers - 2026-02-17

**Paper Count**: 1

---

## 1. WoVR: World Models as Reliable Simulators for Post-Training VLA Policies with RL / WoVR：世界模型作为 RL 训练后 VLA 策略的可靠模拟器

**Date**: 2026-02-15 | **arXiv**: [2602.13977v1](http://arxiv.org/abs/2602.13977v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.13977v1)

**Categories**: cs.RO, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Reinforcement learning (RL) promises to unlock capabilities beyond imitation learning for Vision-Language-Action (VLA) models, but its requirement for massive real-world interaction prevents direct deployment on physical robots. Recent work attempts to use learned world models as simulators for policy optimization, yet closed-loop imagined rollouts inevitably suffer from hallucination and long-horizon error accumulation. Such errors do not merely degrade visual fidelity; they corrupt the optimization signal, encouraging policies to exploit model inaccuracies rather than genuine task progress. We propose WoVR, a reliable world-model-based reinforcement learning framework for post-training VLA policies. Instead of assuming a faithful world model, WoVR explicitly regulates how RL interacts with imperfect imagined dynamics. It improves rollout stability through a controllable action-conditioned video world model, reshapes imagined interaction to reduce effective error depth via Keyframe-Initialized Rollouts, and maintains policy-simulator alignment through World Model-Policy co-evolution. Extensive experiments on LIBERO benchmarks and real-world robotic manipulation demonstrate that WoVR enables stable long-horizon imagined rollouts and effective policy optimization, improving average LIBERO success from 39.95% to 69.2% (+29.3 points) and real-robot success from 61.7% to 91.7% (+30.0 points). These results show that learned world models can serve as practical simulators for reinforcement learning when hallucination is explicitly controlled.

强化学习 (RL) 有望为视觉-语言-动作 (VLA) 模型解锁超越模仿学习的功能，但其对大规模现实世界交互的要求阻碍了直接部署在物理机器人上。最近的工作尝试使用学习的世界模型作为政策优化的模拟器，但闭环想象的推出不可避免地会遭受幻觉和长期错误累积的影响。此类错误不仅会降低视觉保真度，还会降低视觉保真度。它们破坏了优化信号，鼓励政策利用模型的不准确性，而不是真正的任务进展。我们提出了 WoVR，一种可靠的基于世界模型的强化学习框架，用于训练后 VLA 策略。 WoVR 没有假设一个忠实的世界模型，而是明确规范强化学习如何与不完美的想象动态相互作用。它通过可控的动作条件视频世界模型提高了推出稳定性，通过关键帧初始化的推出重塑了想象的交互以减少有效错误深度，并通过世界模型-策略共同进化保持策略-模拟器的一致性。对 LIBERO 基准和现实世界机器人操作的大量实验表明，WoVR 能够实现稳定的长期想象部署和有效的策略优化，将 LIBERO 平均成功率从 39.95% 提高到 69.2%（+29.3 分），将真实机器人成功率从 61.7% 提高到 91.7%（+30.0 分）。这些结果表明，当幻觉受到明确控制时，学习的世界模型可以作为强化学习的实用模拟器。

</details>

---



</details>

<details><summary><b>2026-02-16 (1 papers)</b></summary>

# arXiv World Model Papers - 2026-02-16

**Paper Count**: 1

---

## 1. Information-theoretic analysis of world models in optimal reward maximizers / 最优奖励最大化世界模型的信息论分析

**Date**: 2026-02-13 | **arXiv**: [2602.12963v1](http://arxiv.org/abs/2602.12963v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.12963v1)

**Categories**: cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

An important question in the field of AI is the extent to which successful behaviour requires an internal representation of the world. In this work, we quantify the amount of information an optimal policy provides about the underlying environment. We consider a Controlled Markov Process (CMP) with $n$ states and $m$ actions, assuming a uniform prior over the space of possible transition dynamics. We prove that observing a deterministic policy that is optimal for any non-constant reward function then conveys exactly $n \log m$ bits of information about the environment. Specifically, we show that the mutual information between the environment and the optimal policy is $n \log m$ bits. This bound holds across a broad class of objectives, including finite-horizon, infinite-horizon discounted, and time-averaged reward maximization. These findings provide a precise information-theoretic lower bound on the "implicit world model'' necessary for optimality.

人工智能领域的一个重要问题是成功的行为在多大程度上需要对世界的内部表征。在这项工作中，我们量化了最佳策略提供的有关底层环境的信息量。我们考虑一个具有 $n$ 状态和 $m$ 动作的受控马尔可夫过程 (CMP)，假设在可能的过渡动态空间上有一个统一的先验。我们证明，观察对于任何非恒定奖励函数来说都是最佳的确定性策略可以准确地传达 $n \log m$ 位有关环境的信息。具体来说，我们表明环境和最优策略之间的互信息为 $n \log m$ 位。这一界限适用于广泛的目标，包括有限范围、无限范围贴现和时间平均奖励最大化。这些发现为最优性所需的“隐式世界模型”提供了精确的信息论下界。

</details>

---



</details>

<details><summary><b>2026-02-14 (12 papers)</b></summary>

# arXiv World Model Papers - 2026-02-14

**Paper Count**: 12

---

## 1. The Observer Effect in World Models: Invasive Adaptation Corrupts Latent Physics / 世界模型中的观察者效应：侵入性适应破坏了潜在的物理学

**Date**: 2026-02-12 | **arXiv**: [2602.12218v1](http://arxiv.org/abs/2602.12218v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.12218v1)

**Categories**: cs.LG, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Determining whether neural models internalize physical laws as world models, rather than exploiting statistical shortcuts, remains challenging, especially under out-of-distribution (OOD) shifts. Standard evaluations often test latent capability via downstream adaptation (e.g., fine-tuning or high-capacity probes), but such interventions can change the representations being measured and thus confound what was learned during self-supervised learning (SSL). We propose a non-invasive evaluation protocol, PhyIP. We test whether physical quantities are linearly decodable from frozen representations, motivated by the linear representation hypothesis. Across fluid dynamics and orbital mechanics, we find that when SSL achieves low error, latent structure becomes linearly accessible. PhyIP recovers internal energy and Newtonian inverse-square scaling on OOD tests (e.g., $ρ> 0.90$). In contrast, adaptation-based evaluations can collapse this structure ($ρ\approx 0.05$). These findings suggest that adaptation-based evaluation can obscure latent structures and that low-capacity probes offer a more accurate evaluation of physical world models.

确定神经模型是否将物理定律内化为世界模型，而不是利用统计捷径，仍然具有挑战性，特别是在分布外（OOD）变化的情况下。标准评估通常通过下游适应（例如微调或高容量探测）来测试潜在能力，但此类干预可能会改变正在测量的表示，从而混淆自监督学习（SSL）期间学到的内容。我们提出了一种非侵入性评估协议 PhyIP。在线性表示假设的推动下，我们测试物理量是否可以从冻结表示中线性解码。在流体动力学和轨道力学中，我们发现当 SSL 实现低误差时，潜在结构变得可线性访问。 PhyIP 在 OOD 测试中恢复内能和牛顿平方反比缩放（例如 $ρ> 0.90$）。相反，基于适应的评估可以破坏这种结构（$ρ\approx 0.05$）。这些发现表明，基于适应的评估可以掩盖潜在结构，并且低容量探针可以对物理世界模型提供更准确的评估。

</details>

---

## 2. Accelerating Robotic Reinforcement Learning with Agent Guidance / 通过代理指导加速机器人强化学习

**Date**: 2026-02-12 | **arXiv**: [2602.11978v1](http://arxiv.org/abs/2602.11978v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.11978v1)

**Categories**: cs.RO, cs.AI

<details><summary><b>Abstract / 摘要</b></summary>

Reinforcement Learning (RL) offers a powerful paradigm for autonomous robots to master generalist manipulation skills through trial-and-error. However, its real-world application is stifled by severe sample inefficiency. Recent Human-in-the-Loop (HIL) methods accelerate training by using human corrections, yet this approach faces a scalability barrier. Reliance on human supervisors imposes a 1:1 supervision ratio that limits fleet expansion, suffers from operator fatigue over extended sessions, and introduces high variance due to inconsistent human proficiency. We present Agent-guided Policy Search (AGPS), a framework that automates the training pipeline by replacing human supervisors with a multimodal agent. Our key insight is that the agent can be viewed as a semantic world model, injecting intrinsic value priors to structure physical exploration. By using executable tools, the agent provides precise guidance via corrective waypoints and spatial constraints for exploration pruning. We validate our approach on two tasks, ranging from precision insertion to deformable object manipulation. Results demonstrate that AGPS outperforms HIL methods in sample efficiency. This automates the supervision pipeline, unlocking the path to labor-free and scalable robot learning. Project website: https://agps-rl.github.io/agps.

强化学习 (RL) 为自主机器人提供了一个强大的范例，让其通过反复试验掌握通用操作技能。然而，其实际应用却因严重的样本效率低下而受到抑制。最近的人在环（HIL）方法通过使用人工修正来加速训练，但这种方法面临可扩展性障碍。对人类监督员的依赖强制实行 1:1 的监督比例，这限制了车队的扩张，操作员在长时间的工作中会感到疲劳，并且由于人员熟练程度不一致而带来很大的差异。我们提出了代理引导策略搜索（AGPS），这是一个通过用多模式代理取代人类监督员来自动化训练流程的框架。我们的主要见解是，代理可以被视为语义世界模型，在结构物理探索之前注入内在价值。通过使用可执行工具，代理通过修正路径点和空间约束提供精确的指导，以进行探索修剪。我们在两项任务上验证了我们的方法，从精确插入到可变形对象操作。结果表明，AGPS 在样本效率方面优于 HIL 方法。这实现了监督管道的自动化，开启了免劳动力且可扩展的机器人学习之路。项目网站：https://agps-rl.github.io/agps。

</details>

---

## 3. Where Bits Matter in World Model Planning: A Paired Mixed-Bit Study for Efficient Spatial Reasoning / 比特在世界模型规划中的作用：高效空间推理的配对混合比特研究

**Date**: 2026-02-12 | **arXiv**: [2602.11882v1](http://arxiv.org/abs/2602.11882v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.11882v1)

**Categories**: cs.LG, cs.AI, cs.CV, cs.RO

**Code**: https://github.com/suraj-ranganath/DINO-MBQuant.

<details><summary><b>Abstract / 摘要</b></summary>

Efficient spatial reasoning requires world models that remain reliable under tight precision budgets. We study whether low-bit planning behavior is determined mostly by total bitwidth or by where bits are allocated across modules. Using DINO-WM on the Wall planning task, we run a paired-goal mixed-bit evaluation across uniform, mixed, asymmetric, and layerwise variants under two planner budgets. We observe a consistent three-regime pattern: 8-bit and 6-bit settings remain close to FP16, 3-bit settings collapse, and 4-bit settings are allocation-sensitive. In that transition region, preserving encoder precision improves planning relative to uniform quantization, and near-size asymmetric variants show the same encoder-side direction. In a later strict 22-cell replication with smaller per-cell episode count, the mixed-versus-uniform INT4 sign becomes budget-conditioned, which further highlights the sensitivity of this transition regime. These findings motivate module-aware, budget-aware quantization policies as a broader research direction for efficient spatial reasoning. Code and run artifacts are available at https://github.com/suraj-ranganath/DINO-MBQuant.

高效的空间推理需要世界模型在严格的精度预算下保持可靠。我们研究低位规划行为是否主要由总位宽或位在模块之间分配的位置决定。在 Wall 规划任务上使用 DINO-WM，我们在两个规划器预算下对均匀、混合、不对称和分层变体进行配对目标混合位评估。我们观察到一致的三机制模式：8 位和 6 位设置保持接近 FP16，3 位设置崩溃，4 位设置对分配敏感。在该过渡区域中，保持编码器精度相对于均匀量化改进了规划，并且接近尺寸的不对称变体显示了相同的编码器侧方向。在后来的严格 22 细胞复制中，每个细胞的情节数更小，混合与均匀的 INT4 符号变得受预算限制，这进一步凸显了这种过渡机制的敏感性。这些发现激发了模块感知、预算感知的量化策略作为高效空间推理的更广泛的研究方向。代码和运行工件可在 https://github.com/suraj-ranganath/DINO-MBQuant 获取。

</details>

---

## 4. Budget-Constrained Agentic Large Language Models: Intention-Based Planning for Costly Tool Use / 预算受限的代理大型语言模型：基于意图的昂贵工具使用规划

**Date**: 2026-02-12 | **arXiv**: [2602.11541v1](http://arxiv.org/abs/2602.11541v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.11541v1)

**Categories**: cs.AI, cs.LG

<details><summary><b>Abstract / 摘要</b></summary>

We study budget-constrained tool-augmented agents, where a large language model must solve multi-step tasks by invoking external tools under a strict monetary budget. We formalize this setting as sequential decision making in context space with priced and stochastic tool executions, making direct planning intractable due to massive state-action spaces, high variance of outcomes and prohibitive exploration cost. To address these challenges, we propose INTENT, an inference-time planning framework that leverages an intention-aware hierarchical world model to anticipate future tool usage, risk-calibrated cost, and guide decisions online. Across cost-augmented StableToolBench, INTENT strictly enforces hard budget feasibility while substantially improving task success over baselines, and remains robust under dynamic market shifts such as tool price changes and varying budgets.

我们研究预算受限的工具增强代理，其中大型语言模型必须在严格的货币预算下通过调用外部工具来解决多步骤任务。我们将这种设置形式化为上下文空间中具有定价和随机工具执行的顺序决策，由于巨大的状态动作空间、结果的高方差和令人望而却步的探索成本，使得直接规划变得棘手。为了应对这些挑战，我们提出了 INTENT，这是一种推理时间规划框架，它利用意图感知的分层世界模型来预测未来的工具使用、风险校准成本并指导在线决策。在成本增加的 StableToolBench 中，INTENT 严格执行硬预算可行性，同时大幅提高任务成功率（较基准），并在工具价格变化和预算变化等动态市场变化下保持稳健。

</details>

---

## 5. LDA-1B: Scaling Latent Dynamics Action Model via Universal Embodied Data Ingestion / LDA-1B：通过通用嵌入数据摄取扩展潜在动态动作模型

**Date**: 2026-02-12 | **arXiv**: [2602.12215v1](http://arxiv.org/abs/2602.12215v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.12215v1)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Recent robot foundation models largely rely on large-scale behavior cloning, which imitates expert actions but discards transferable dynamics knowledge embedded in heterogeneous embodied data. While the Unified World Model (UWM) formulation has the potential to leverage such diverse data, existing instantiations struggle to scale to foundation-level due to coarse data usage and fragmented datasets. We introduce LDA-1B, a robot foundation model that scales through universal embodied data ingestion by jointly learning dynamics, policy, and visual forecasting, assigning distinct roles to data of varying quality. To support this regime at scale, we assemble and standardize EI-30k, an embodied interaction dataset comprising over 30k hours of human and robot trajectories in a unified format. Scalable dynamics learning over such heterogeneous data is enabled by prediction in a structured DINO latent space, which avoids redundant pixel-space appearance modeling. Complementing this representation, LDA-1B employs a multi-modal diffusion transformer to handle asynchronous vision and action streams, enabling stable training at the 1B-parameter scale. Experiments in simulation and the real world show LDA-1B outperforms prior methods (e.g., $π_{0.5}$) by up to 21\%, 48\%, and 23\% on contact-rich, dexterous, and long-horizon tasks, respectively. Notably, LDA-1B enables data-efficient fine-tuning, gaining 10\% by leveraging 30\% low-quality trajectories typically harmful and discarded.

最近的机器人基础模型在很大程度上依赖于大规模行为克隆，它模仿专家的行为，但丢弃了嵌入异构数据中的可转移的动力学知识。虽然统一世界模型 (UWM) 公式有潜力利用如此多样化的数据，但由于粗略的数据使用和分散的数据集，现有的实例很难扩展到基础级别。我们引入了 LDA-1B，这是一种机器人基础模型，通过联合学习动态、策略和视觉预测，为不同质量的数据分配不同的角色，通过通用的具体数据摄取进行扩展。为了大规模支持这种制度，我们组装并标准化了 EI-30k，这是一个具体的交互数据集，以统一的格式包含超过 30,000 小时的人类和机器人轨迹。通过在结构化 DINO 潜在空间中进行预测，可以实现对此类异构数据的可扩展动态学习，从而避免冗余的像素空间外观建模。作为对这种表示的补充，LDA-1B 采用多模态扩散变压器来处理异步视觉和动作流，从而实现 1B 参数规模的稳定训练。模拟和现实世界的实验表明，在接触丰富、灵巧和长视野任务上，LDA-1B 的性能分别比先前方法（例如 $π_{0.5}$）高出 21\%、48\% 和 23\%。值得注意的是，LDA-1B 能够实现数据高效的微调，通过利用 30% 的通常有害和丢弃的低质量轨迹，获得 10% 的增益。

</details>

---

## 6. VLAW: Iterative Co-Improvement of Vision-Language-Action Policy and World Model / VLAW：愿景-语言-行动政策和世界模型的迭代共同改进

**Date**: 2026-02-12 | **arXiv**: [2602.12063v1](http://arxiv.org/abs/2602.12063v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.12063v1)

**Categories**: cs.RO

**Project**: https://sites.google.com/view/vla-w  <details><summary><b>Abstract / 摘要</b></summary>

The goal of this paper is to improve the performance and reliability of vision-language-action (VLA) models through iterative online interaction. Since collecting policy rollouts in the real world is expensive, we investigate whether a learned simulator-specifically, an action-conditioned video generation model-can be used to generate additional rollout data. Unfortunately, existing world models lack the physical fidelity necessary for policy improvement: they are predominantly trained on demonstration datasets that lack coverage of many different physical interactions (particularly failure cases) and struggle to accurately model small yet critical physical details in contact-rich object manipulation. We propose a simple iterative improvement algorithm that uses real-world roll-out data to improve the fidelity of the world model, which can then, in turn, be used to generate supplemental synthetic data for improving the VLA model. In our experiments on a real robot, we use this approach to improve the performance of a state-of-the-art VLA model on multiple downstream tasks. We achieve a 39.2% absolute success rate improvement over the base policy and 11.6% improvement from training with the generated synthetic rollouts. Videos can be found at this anonymous website: https://sites.google.com/view/vla-w

本文的目标是通过迭代在线交互来提高视觉-语言-动作（VLA）模型的性能和可靠性。由于在现实世界中收集策略推出的成本很高，因此我们研究了是否可以使用学习的模拟器（具体而言，动作条件视频生成模型）来生成额外的推出数据。不幸的是，现有的世界模型缺乏政策改进所需的物理保真度：它们主要是在演示数据集上进行训练的，这些数据集缺乏对许多不同物理交互（特别是失败案例）的覆盖，并且很难在接触丰富的对象操作中准确地模拟微小但关键的物理细节。我们提出了一种简单的迭代改进算法，该算法使用现实世界的转出数据来提高世界模型的保真度，然后可以使用该算法生成补充合成数据以改进 VLA 模型。在我们对真实机器人的实验中，我们使用这种方法来提高最先进的 VLA 模型在多个下游任务上的性能。与基本策略相比，我们的绝对成功率提高了 39.2%，通过生成的综合部署进行训练，绝对成功率提高了 11.6%。视频可以在这个匿名网站上找到：https://sites.google.com/view/vla-w

</details>

---

## 7. HAIC: Humanoid Agile Object Interaction Control via Dynamics-Aware World Model / HAIC：通过动态感知世界模型进行人形敏捷对象交互控制

**Date**: 2026-02-12 | **arXiv**: [2602.11758v1](http://arxiv.org/abs/2602.11758v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.11758v1)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Humanoid robots show promise for complex whole-body tasks in unstructured environments. Although Human-Object Interaction (HOI) has advanced, most methods focus on fully actuated objects rigidly coupled to the robot, ignoring underactuated objects with independent dynamics and non-holonomic constraints. These introduce control challenges from coupling forces and occlusions. We present HAIC, a unified framework for robust interaction across diverse object dynamics without external state estimation. Our key contribution is a dynamics predictor that estimates high-order object states (velocity, acceleration) solely from proprioceptive history. These predictions are projected onto static geometric priors to form a spatially grounded dynamic occupancy map, enabling the policy to infer collision boundaries and contact affordances in blind spots. We use asymmetric fine-tuning, where a world model continuously adapts to the student policy's exploration, ensuring robust state estimation under distribution shifts. Experiments on a humanoid robot show HAIC achieves high success rates in agile tasks (skateboarding, cart pushing/pulling under various loads) by proactively compensating for inertial perturbations, and also masters multi-object long-horizon tasks like carrying a box across varied terrain by predicting the dynamics of multiple objects.

人形机器人有望在非结构化环境中执行复杂的全身任务。尽管人机交互（HOI）已经取得了进步，但大多数方法都专注于与机器人刚性耦合的完全驱动物体，而忽略了具有独立动力学和非完整约束的欠驱动物体。这些引入了来自耦合力和遮挡的控制挑战。我们提出了 HAIC，这是一个无需外部状态估计即可跨不同对象动态进行鲁棒交互的统一框架。我们的主要贡献是一个动力学预测器，它仅根据本体感受历史来估计高阶物体状态（速度、加速度）。这些预测被投影到静态几何先验上，形成基于空间的动态占用图，使策略能够推断碰撞边界和盲点中的接触可供性。我们使用不对称微调，其中世界模型不断适应学生政策的探索，确保分布变化下的稳健状态估计。在人形机器人上的实验表明，HAIC 通过主动补偿惯性扰动，在敏捷任务（滑板、各种负载下推/拉车）中取得了很高的成功率，并且还通过预测多个物体的动态来掌握多物体长视距任务，例如在不同地形上搬运箱子。

</details>

---

## 8. Causal-JEPA: Learning World Models through Object-Level Latent Interventions / 因果-JEPA：通过对象级潜在干预学习世界模型

**Date**: 2026-02-11 | **arXiv**: [2602.11389v1](http://arxiv.org/abs/2602.11389v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.11389v1)

**Categories**: cs.AI

**Code**: https://github.com/galilai-group/cjepa.

<details><summary><b>Abstract / 摘要</b></summary>

World models require robust relational understanding to support prediction, reasoning, and control. While object-centric representations provide a useful abstraction, they are not sufficient to capture interaction-dependent dynamics. We therefore propose C-JEPA, a simple and flexible object-centric world model that extends masked joint embedding prediction from image patches to object-centric representations. By applying object-level masking that requires an object's state to be inferred from other objects, C-JEPA induces latent interventions with counterfactual-like effects and prevents shortcut solutions, making interaction reasoning essential. Empirically, C-JEPA leads to consistent gains in visual question answering, with an absolute improvement of about 20\% in counterfactual reasoning compared to the same architecture without object-level masking. On agent control tasks, C-JEPA enables substantially more efficient planning by using only 1\% of the total latent input features required by patch-based world models, while achieving comparable performance. Finally, we provide a formal analysis demonstrating that object-level masking induces a causal inductive bias via latent interventions. Our code is available at https://github.com/galilai-group/cjepa.

世界模型需要强大的关系理解来支持预测、推理和控制。虽然以对象为中心的表示提供了有用的抽象，但它们不足以捕获依赖于交互的动态。因此，我们提出了 C-JEPA，这是一种简单而灵活的以对象为中心的世界模型，它将蒙版联合嵌入预测从图像块扩展到以对象为中心的表示。通过应用需要从其他对象推断对象状态的对象级屏蔽，C-JEPA 会引发具有类似反事实效果的潜在干预，并阻止捷径解决方案，从而使交互推理变得至关重要。根据经验，C-JEPA 在视觉问答方面带来了持续的收益，与没有对象级屏蔽的相同架构相比，反事实推理绝对提高了约 20%。在代理控制任务上，C-JEPA 仅使用基于补丁的世界模型所需的总潜在输入特征的 1%，从而实现了更高效的规划，同时实现了可比的性能。最后，我们提供了正式的分析，证明对象级掩蔽通过潜在干预诱发了因果归纳偏差。我们的代码可在 https://github.com/galilai-group/cjepa 获取。

</details>

---

## 9. H-WM: Robotic Task and Motion Planning Guided by Hierarchical World Model / H-WM：分层世界模型引导的机器人任务和运动规划

**Date**: 2026-02-11 | **arXiv**: [2602.11291v1](http://arxiv.org/abs/2602.11291v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.11291v1)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

World models are becoming central to robotic planning and control, as they enable prediction of future state transitions. Existing approaches often emphasize video generation or natural language prediction, which are difficult to directly ground in robot actions and suffer from compounding errors over long horizons. Traditional task and motion planning relies on symbolic logic world models, such as planning domains, that are robot-executable and robust for long-horizon reasoning. However, these methods typically operate independently of visual perception, preventing synchronized symbolic and perceptual state prediction. We propose a Hierarchical World Model (H-WM) that jointly predicts logical and visual state transitions within a unified bilevel framework. H-WM combines a high-level logical world model with a low-level visual world model, integrating the robot-executable, long-horizon robustness of symbolic reasoning with perceptual grounding from visual observations. The hierarchical outputs provide stable and consistent intermediate guidance for long-horizon tasks, mitigating error accumulation and enabling robust execution across extended task sequences. To train H-WM, we introduce a robotic dataset that aligns robot motion with symbolic states, actions, and visual observations. Experiments across vision-language-action (VLA) control policies demonstrate the effectiveness and generality of the approach.

世界模型正在成为机器人规划和控制的核心，因为它们能够预测未来的状态转换。现有的方法通常强调视频生成或自然语言预测，这些方法很难直接反映机器人的动作，并且在长期范围内会出现复合错误。传统的任务和运动规划依赖于符号逻辑世界模型，例如规划域，这些模型是机器人可执行的并且对于长视野推理来说是鲁棒的。然而，这些方法通常独立于视觉感知进行操作，从而阻止了同步的符号和感知状态预测。我们提出了一种分层世界模型（H-WM），它在统一的双层框架内联合预测逻辑和视觉状态转换。 H-WM 将高级逻辑世界模型与低级视觉世界模型相结合，将机器人可执行的符号推理的长期鲁棒性与视觉观察的感知基础相结合。分层输出为长期任务提供稳定一致的中间指导，减少错误累积并实现跨扩展任务序列的稳健执行。为了训练 H-WM，我们引入了一个机器人数据集，该数据集将机器人运动与符号状态、动作和视觉观察对齐。视觉-语言-动作（VLA）控制策略的实验证明了该方法的有效性和通用性。

</details>

---

## 10. RISE: Self-Improving Robot Policy with Compositional World Model / RISE：利用组合世界模型自我改进机器人政策

**Date**: 2026-02-11 | **arXiv**: [2602.11075v1](http://arxiv.org/abs/2602.11075v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.11075v1)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Despite the sustained scaling on model capacity and data acquisition, Vision-Language-Action (VLA) models remain brittle in contact-rich and dynamic manipulation tasks, where minor execution deviations can compound into failures. While reinforcement learning (RL) offers a principled path to robustness, on-policy RL in the physical world is constrained by safety risk, hardware cost, and environment reset. To bridge this gap, we present RISE, a scalable framework of robotic reinforcement learning via imagination. At its core is a Compositional World Model that (i) predicts multi-view future via a controllable dynamics model, and (ii) evaluates imagined outcomes with a progress value model, producing informative advantages for the policy improvement. Such compositional design allows state and value to be tailored by best-suited yet distinct architectures and objectives. These components are integrated into a closed-loop self-improving pipeline that continuously generates imaginary rollouts, estimates advantages, and updates the policy in imaginary space without costly physical interaction. Across three challenging real-world tasks, RISE yields significant improvement over prior art, with more than +35% absolute performance increase in dynamic brick sorting, +45% for backpack packing, and +35% for box closing, respectively.

尽管模型容量和数据采集不断扩展，但视觉-语言-动作 (VLA) 模型在接触丰富的动态操作任务中仍然很脆弱，在这些任务中，微小的执行偏差可能会导致失败。虽然强化学习 (RL) 提供了实现稳健性的原则性途径，但物理世界中的策略 RL 受到安全风险、硬件成本和环境重置的限制。为了弥补这一差距，我们推出了 RISE，这是一个通过想象力进行机器人强化学习的可扩展框架。其核心是组合世界模型，（i）通过可控动态模型预测多视角未来，（ii）通过进步价值模型评估想象的结果，为政策改进提供信息优势。这种组合设计允许通过最适合但独特的架构和目标来定制状态和价值。这些组件被集成到一个闭环自我改进管道中，该管道不断生成想象中的部署、估计优势并更新想象空间中的策略，而无需昂贵的物理交互。在三个具有挑战性的现实世界任务中，RISE 比现有技术取得了显着改进，动态砖块分类的绝对性能提高了 35% 以上，背包包装的绝对性能提高了 45%，盒子关闭的性能提高了 35%。

</details>

---

## 11. ContactGaussian-WM: Learning Physics-Grounded World Model from Videos / ContactGaussian-WM：从视频中学习基于物理的世界模型

**Date**: 2026-02-11 | **arXiv**: [2602.11021v1](http://arxiv.org/abs/2602.11021v1) | **PDF**: [Link](http://arxiv.org/pdf/2602.11021v1)

**Categories**: cs.RO, cs.AI, cs.CV

<details><summary><b>Abstract / 摘要</b></summary>

Developing world models that understand complex physical interactions is essential for advancing robotic planning and simulation.However, existing methods often struggle to accurately model the environment under conditions of data scarcity and complex contact-rich dynamic motion.To address these challenges, we propose ContactGaussian-WM, a differentiable physics-grounded rigid-body world model capable of learning intricate physical laws directly from sparse and contact-rich video sequences.Our framework consists of two core components: (1) a unified Gaussian representation for both visual appearance and collision geometry, and (2) an end-to-end differentiable learning framework that differentiates through a closed-form physics engine to infer physical properties from sparse visual observations.Extensive simulations and real-world evaluations demonstrate that ContactGaussian-WM outperforms state-of-the-art methods in learning complex scenarios, exhibiting robust generalization capabilities.Furthermore, we showcase the practical utility of our framework in downstream applications, including data synthesis and real-time MPC.

开发理解复杂物理交互的世界模型对于推进机器人规划和仿真至关重要。然而，现有方法通常很难在数据稀缺和复杂的接触丰富的动态运动条件下准确地对环境进行建模。为了应对这些挑战，我们提出了 ContactGaussian-WM，这是一种基于物理的可微刚体世界模型，能够直接从稀疏和接触丰富的视频序列中学习复杂的物理定律。我们的框架由两个核心组件组成：（1）视觉外观和碰撞的统一高斯表示（2）端到端可微学习框架，通过封闭式物理引擎进行区分，从稀疏的视觉观察中推断物理属性。广泛的模拟和现实世界评估表明，ContactGaussian-WM 在学习复杂场景方面优于最先进的方法，展现出强大的泛化能力。此外，我们展示了我们的框架在下游应用中的实际效用，包括数据合成和实时 MPC。

</details>

---

## 12. Scaling World Model for Hierarchical Manipulation Policies / 分级操纵策略的扩展世界模型

**Date**: 2026-02-11 | **arXiv**: [2602.10983v2](http://arxiv.org/abs/2602.10983v2) | **PDF**: [Link](http://arxiv.org/pdf/2602.10983v2)

**Categories**: cs.RO

<details><summary><b>Abstract / 摘要</b></summary>

Vision-Language-Action (VLA) models are promising for generalist robot manipulation but remain brittle in out-of-distribution (OOD) settings, especially with limited real-robot data. To resolve the generalization bottleneck, we introduce a hierarchical Vision-Language-Action framework \our{} that leverages the generalization of large-scale pre-trained world model for robust and generalizable VIsual Subgoal TAsk decomposition VISTA. Our hierarchical framework \our{} consists of a world model as the high-level planner and a VLA as the low-level executor. The high-level world model first divides manipulation tasks into subtask sequences with goal images, and the low-level policy follows the textual and visual guidance to generate action sequences. Compared to raw textual goal specification, these synthesized goal images provide visually and physically grounded details for low-level policies, making it feasible to generalize across unseen objects and novel scenarios. We validate both visual goal synthesis and our hierarchical VLA policies in massive out-of-distribution scenarios, and the performance of the same-structured VLA in novel scenarios could boost from 14% to 69% with the guidance generated by the world model. Results demonstrate that our method outperforms previous baselines with a clear margin, particularly in out-of-distribution scenarios. Project page: \href{https://vista-wm.github.io/}{https://vista-wm.github.io}

视觉-语言-动作（VLA）模型对于通用机器人操作很有希望，但在分布外（OOD）设置中仍然很脆弱，尤其是在真实机器人数据有限的情况下。为了解决泛化瓶颈，我们引入了分层视觉-语言-动作框架 \our{}，该框架利用大规模预训练世界模型的泛化来实现稳健且可泛化的视觉子目标任务分解 VISTA。我们的分层框架 \our{} 由作为高级规划器的世界模型和作为低级执行器的 VLA 组成。高层世界模型首先将操作任务划分为具有目标图像的子任务序列，低层策略遵循文本和视觉指导来生成动作序列。与原始文本目标规范相比，这些合成的目标图像为低级策略提供了视觉和物理基础的细节，使得在未见过的物体和新场景中进行泛化成为可能。我们在大规模分布外场景中验证了视觉目标合成和分层 VLA 策略，并且在世界模型生成的指导下，相同结构的 VLA 在新颖场景中的性能可以从 14% 提高到 69%。结果表明，我们的方法明显优于以前的基线，特别是在分布外的情况下。项目页面：\href{https://vista-wm.github.io/}{https://vista-wm.github.io}

</details>

---



</details>

<!-- PAPERS_CONTENT_END -->
