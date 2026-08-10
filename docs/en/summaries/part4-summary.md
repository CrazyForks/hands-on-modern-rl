---
title: Part IV Summary
sitemap: false
---

::: warning TODO: Summaries removed from Chinese side (2026-06-25)
The Chinese restructure commit (`d0d5925`) deleted `docs/summaries/` entirely. These per-part summary pages no longer have a Chinese counterpart. They are kept here as translation reference and should be either removed or re-anchored to the new Part I–VII structure on the next translation pass.
:::

# Multimodal and Frontier Topics - Knowledge Summary

## What Did We Learn in This Part?

The later chapters cover frontier directions of reinforcement learning in the modern LLM era. Each topic represents a jump from core algorithms to cutting-edge applications. After finishing this part, you should understand:

- **VLM RL**: reinforcement learning for vision-language models; differential learning rates; fine-grained visual penalties and alignment with multi-step logical reasoning.
- **Future trends**: embodied intelligence (continuous control and robotics), test-time compute and self-play, offline reinforcement learning, and multi-agent RL.

Now let us review the chapters.

## Chapter 23: VLM Reinforcement Learning - Teaching Vision Models to Reason

Once a model gains "eyes," RL becomes harder again. VLM (vision-language model) RL faces differential learning rates (a smaller learning rate for the vision encoder), difficult reward attribution (are visual tokens or text tokens responsible for the mistake?), and penalties for visual hallucinations. We showed how fine-grained reward design can teach a VLM not only to "see" images, but also to perform multi-step logical reasoning grounded in those images.

## Further Directions Across Chapters 9-12, 17, 26, and 29

### Embodied Intelligence: From Simulation to Reality

Continuous control and embodied intelligence are how RL enters the physical world. We discussed algorithms such as DDPG (deterministic policies for continuous actions), TD3 (clipped double Q + delayed updates to reduce overestimation), and SAC (a maximum-entropy objective that balances exploration and exploitation). We also discussed sim-to-real transfer and domain randomization in robotic control (for example, quadruped robots).

### Test-Time Compute and Self-Play

Test-time compute gives models the ability to "think a bit longer before answering." Systems such as OpenAI o1/o3 and DeepSeek-R1 suggest that RL training can produce emergent internal search and verification behaviors. Self-play pushes capability further without human labels by having a generator and a judge compete in an adversarial loop.

### Offline RL and Multi-Agent Systems

**Offline reinforcement learning** addresses settings where we cannot do online trial-and-error, learning policies from fixed historical datasets via methods such as CQL, IQL, and Decision Transformers. **Multi-agent RL** (MARL) studies cooperation and competition among multiple LLM agents in a shared environment, introducing new challenges such as role specialization, non-stationarity, and cross-role credit assignment.

## Summary

The book began with CartPole, then moved through MDPs, DQN, policy gradients, PPO, DPO/GRPO, RLHF, agentic RL, VLM RL, continuous control and embodied intelligence, and finally arrived at frontier trends. Every concept on this path connects to the next: Bellman recursion runs through Q-learning and DQN; the policy gradient theorem underlies REINFORCE, Actor-Critic, and PPO; PPO clipping is inherited by GRPO; DPO's implicit reward inspires RLVR-style rule verification; and continuous-control algorithms bring RL into the physical world. Reinforcement learning is not an isolated discipline, but a unified methodology for "learning decisions from experience."

## Learning Roadmap: Where to Go Next

By this point, we have completed the journey of the book. From CartPole in Chapter 1 to frontier trends, you now have the core theory and practical skills of modern RL. What should you do next? Here is a layered roadmap.

### Beginner Practice

- **This book + the companion code repo**: rerun all experiments, then modify hyperparameters and observe how training behavior changes.
- **Gymnasium official documentation**: try more environments (LunarLander, BipedalWalker) and build intuition for different RL algorithms.
- **Stable-Baselines3 tutorials**: implement DQN/PPO/SAC quickly using a mature library, and compare with your own implementations.

### Advanced Deepening

- **Careful reading of original papers**: PPO (Schulman 2017), DPO (Rafailov 2023), GRPO (Shao 2024). Understand each design choice.
- **HuggingFace TRL library**: an industry-grade LLM alignment toolkit supporting full pipelines for DPO/PPO/GRPO.
- **VERL / OpenRLHF**: large-scale RLHF training frameworks; learn engineering details (distributed training, reward-model services, sampling optimizations).

### Research Frontiers

- **Efficient RL training**: reduce sample requirements, lower memory usage, speed up training. This is a core bottleneck for real-world deployment.
- **Safety RL**: constrained optimization, red-teaming, alignment tax; ensure RL-trained models do not exhibit harmful behaviors.
- **Multi-agent collaboration with LLMs**: combining MARL with LLM roles; how multiple roles learn to collaborate efficiently via RL.
- **Agentic RL**: the direction discussed in Chapter 19; one of the most active research directions in 2025-2026.
- **Self-play and self-evolution**: can models keep breaking limits through self-play?

| Stage    | Goal                                       | Suggested Resources                                      | Time Estimate |
| -------- | ------------------------------------------ | -------------------------------------------------------- | ------------- |
| Beginner | master core algorithms and intuition       | this book + Gymnasium + SB3                              | 1-2 months    |
| Advanced | understand industry-grade training details | paper reading + TRL + VERL                               | 2-4 months    |
| Research | track frontiers and contribute             | top-conference papers + open-source projects + community | ongoing       |

## Closing Words

From balancing a pole in CartPole to eliciting reasoning with GRPO, from experience replay in DQN to multi-turn interaction in agentic RL, we have walked through the core journey of modern RL. The central idea of this book is:

**RL is not merely a pile of formulas; it is a general methodology for letting agents learn from experience.**

Its mathematical framework (MDPs, policy gradients, Bellman equations) is stable, but its application domains keep expanding: from games to robots, from language models to autonomous agents.

The table below reviews the book's core concepts and how they connect:

| Chapters | Core Concepts               | One-Line Summary                                          |
| -------- | --------------------------- | --------------------------------------------------------- |
| 1        | CartPole                    | RL intuition through a first control experiment             |
| 2-4      | MDP, values, classical RL    | the mathematical language and classical methods of RL       |
| 5        | DQN                         | deep learning + Q-learning = learning from pixels            |
| 6        | policy gradients, REINFORCE | optimize policies directly; bypass Q-values                  |
| 7-8      | Actor-Critic and PPO        | stable policy optimization; foundation of LLM alignment      |
| 13       | RLHF pipeline               | the full engineering stack of industrial alignment           |
| 15-16    | DPO, GRPO, RLVR             | preference alignment and verifiable rewards                  |
| 20       | agentic RL                  | training agents for multi-turn tool interactions              |
| 24       | VLM RL                      | reinforcement learning for vision-language models             |
| 9-12, 17, 26, 29 | further directions | continuous control, offline RL, reasoning, embodiment, self-play |

Your current knowledge is enough to understand most frontier work in RL in 2025-2026. More importantly, you have gained a way of thinking: **how to model a real problem as an RL problem, design a reward function, choose an algorithm, and build training infrastructure.** This way of thinking is more valuable than any single algorithm.

The RL story is still unfolding. We do not know what will happen next, and that is what makes the field exciting. Welcome to the journey.

> Return to the [Preface](/preface/intro) or continue with the [Appendix](/en/appendix_industrial_training/intro).
