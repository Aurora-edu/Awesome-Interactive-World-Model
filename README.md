<div align="center">

# <img src="data/logo.png" width="50" style="vertical-align:middle;"> Awesome Interactive World Models

**📜 Interactive World Model papers organized by core research challenges.** </br>
👉 **Recommended: View the [paper list on our website](https://easontut.github.io/Awesome-Interactive-World-Model/) for a better browsing experience.**
</div>

## 🚩 News & Updates
_Major updates and announcements are shown below. Scroll for full timeline._

🔥 **[2026-5] Repository Launch** — Awesome Interactive World Models is now live! We're building a curated collection of Interactive World Model papers, systematically categorized by key research problems. See [CONTRIBUTING.md](CONTRIBUTING.md) for how to contribute.

💡 **[Ongoing] Community Contributions Welcome** — Help us maintain the most up-to-date world models resource! Submit papers via PR or contact us at [email](mailto:yixuanye12@gmail.com).

⭐ **[Ongoing] Support This Project** — If you find this useful, please [cite](#citation) our work and give us a star. Share with your research community!

---
## Overview
  - 🌐 [General World Model](#general-world-model)
  - 📊 [Benchmark](#benchmark)
  - 💾 [Dataset](#dataset)
  - 🎬 [Long Video Generation](#long-video-generation)
  - 🧠 [Memory Consistency](#memory-consistency)
  - 🎮 [Action Control](#action-control)
  - 🖱️ [Interactive](#interactive)
  - 🔧 [Post-Training](#post-training)
  - ⚙️ [Physics](#physics)
  - 📏 [Evaluation](#evaluation)
  - 📝 [Citation](#citation)

---
<table align="center" width="100%" border="0" cellspacing="0" cellpadding="0" style="border:none;">
  <tr>
    <td align="center" style="border:none;">🌟 <b>Classic</b></td>
    <td align="center" style="border:none;">✅ <b>Open Source</b></td>
    <td align="center" style="border:none;">❌️ <b>Not Open Source</b></td>
  </tr>
</table>

**Badge Guide.** `🌟` marks representative or category-defining work. `✅` indicates that public resources such as code, data, model weights, demos, or an official project page are available. `❌️` indicates that no public implementation or resource has been found yet.

## General World Model

✅🌟(Minute-level Memory)[Lingbot-World:Advancing Open-source World Models](https://arxiv.org/abs/2601.20540)

✅🌟(First open-source real-time interactive World Model)[Matrix-game 2.0: An open-source real-time and streaming interactive world model](https://arxiv.org/abs/2508.13009)

❌️[Yan: Foundational Interactive Video Generation](https://arxiv.org/abs/2508.08601)

❌️[Genie: Generative Interactive Environments](https://arxiv.org/abs/2402.15391)

✅[Yume-1.5: A Text-Controlled Interactive World Generation Model](https://arxiv.org/abs/2512.22096)

❌️[RELIC: Interactive Video World Model with Long-Horizon Memory](https://arxiv.org/abs/2512.04040)

❌️[Hunyuan-GameCraft-2: Instruction-following Interactive Game World Model](https://arxiv.org/abs/2511.23429)

✅[Hunyuan-GameCraft: High-dynamic Interactive Game Video Generation with Hybrid History Condition](https://arxiv.org/abs/2506.17201)

✅[HY-World 1.5: A Systematic Framework for Interactive World Modeling with Real-Time Latency and Geometric Consistency](https://3d-models.hunyuan.tencent.com/world/world1_5/HYWorld_1.5_Tech_Report.pdf)

✅[Astra: General Interactive World Model with Autoregressive Denoising](https://arxiv.org/abs/2512.08931)

❌️[PAN: A World Model for General, Interactable, and Long-Horizon World Simulation](https://arxiv.org/abs/2511.09057)

✅[SANA-WM: Efficient Minute-Scale World Modeling with Hybrid Linear Diffusion Transformer](https://arxiv.org/abs/2605.15178)

✅[Matrix-Game 3.0: Real-Time and Streaming Interactive World Model with Long-Horizon Memory](https://arxiv.org/abs/2604.08995)

✅[InSpatio-WorldFM: An Open-Source Real-Time Generative Frame Model](https://arxiv.org/abs/2603.11911)

✅[DreamX-World: A General-Purpose Interactive World Model](https://github.com/AMAP-ML/DreamX-World)

✅[Warp-as-History: Generalizable Camera-Controlled Video Generation from One Training Video](https://arxiv.org/abs/2605.15182)

## Benchmark

✅🌟(First Open Domain Memory & Action Benchmark)[MIND: Benchmarking Memory Consistency and Action Control in World Models](https://arxiv.org/abs/2602.08025)

✅[WorldScore: A Unified Evaluation Benchmark for World Generation](https://arxiv.org/abs/2504.00983)

✅[WorldModelBench: Judging Video Generation Models As World Models](https://arxiv.org/abs/2502.20694)

✅[WorldSimBench: Towards Video Generation Models as World Simulators](https://arxiv.org/abs/2410.18072)

✅[Toward Memory-Aided World Models: Benchmarking via Spatial Consistency](https://arxiv.org/abs/2505.22976)


## Dataset

✅ [Sekai: A Video Dataset towards World Exploration](https://arxiv.org/abs/2506.15675)

✅ [SpatialVID: A Large-Scale Video Dataset with Spatial Annotations](https://arxiv.org/abs/2509.09676)

✅ [WildWorld: A Large-Scale Dataset for Dynamic World Modeling with Actions and Explicit State toward Generative ARPG](https://arxiv.org/abs/2603.23497)

✅ [OmniWorld: A Multi-Domain and Multi-Modal Dataset for 4D World Modeling](https://arxiv.org/abs/2509.12201)

✅ [GameGen-X: Open-World Video Game Dataset](https://arxiv.org/abs/2411.00769)

## Long Video Generation
✅ 🌟(First architecture supporting arbitrary step OPD) [AnyFlow: Any-Step Video Diffusion Model with On-Policy Flow Map Distillation](https://arxiv.org/abs/2605.13724)

✅🌟(ODE perspective)[Causal Forcing: Autoregressive Diffusion Distillation Done Right for High-Quality Real-Time Interactive Video Generation](https://arxiv.org/abs/2602.02214)

❌️🌟(Solves Self-Forcing issues)[Self-Forcing++: Towards Minute-Scale High-Quality Video Generation](https://arxiv.org/abs/2510.02283)

✅🌟(DMD perspective)[Self Forcing: Bridging the Train-Test Gap in Autoregressive Video Diffusion](https://arxiv.org/abs/2506.08009)

✅🌟(Training techniques)[Diffusion Forcing: Next-token Prediction Meets Full-Sequence Diffusion](https://arxiv.org/abs/2407.01392)

✅🌟(Teacher->Student acceleration)[From Slow Bidirectional to Fast Autoregressive Video Diffusion Models](https://arxiv.org/abs/2412.07772v4)

✅🌟(Context compression)[Frame Context Packing and Drift Prevention in Next-Frame-Prediction Video Diffusion Models](https://arxiv.org/abs/2504.12626)

❌️🌟(Learnable sparse attention routing)[Mixture of Contexts for Long Video Generation](https://arxiv.org/abs/2508.21058)

❌️🌟(Compression recovery training)[Pretraining Frame Preservation in Autoregressive Video Memory Compression](https://arxiv.org/abs/2512.23851)

✅[Context Forcing: Consistent Autoregressive Video Generation with Long Context](https://arxiv.org/abs/2602.06028)

✅[Reward Forcing: Efficient Streaming Video Generation with Rewarded Distribution Matching Distillation](https://arxiv.org/abs/2512.04678)

✅[Latent Forcing: Reordering the Diffusion Trajectory for Pixel-Space Image Generation](https://arxiv.org/abs/2602.11401)

✅[FAR: Frame Autoregressive Model for Both Short- and Long-Context Video Modeling](https://arxiv.org/abs/2503.19325)

✅[Rolling Forcing: Autoregressive Long Video Diffusion in Real Time](https://arxiv.org/abs/2509.25161)

❌️[Mode Seeking meets Mean Seeking for Fast Long Video Generation](https://arxiv.org/abs/2602.24289)

❌️[LIVE: Long-horizon Interactive Video World Modeling](https://arxiv.org/abs/2602.03747)

✅[Rolling Sink: Bridging Limited-Horizon Training and Open-Ended Testing in Autoregressive Video Diffusion](https://arxiv.org/abs/2602.07775)

❌️[LIGHT FORCING: Accelerating Autoregressive Video Diffusion via Sparse Attention](https://arxiv.org/abs/2602.04789)

✅ [Causal Forcing++: Scalable Few-Step Autoregressive Diffusion Distillation for Real-Time Interactive Video Generation](https://arxiv.org/abs/2605.15141)

✅[VideoSSM: Autoregressive Long Video Generation with Hybrid State Space Memory](https://arxiv.org/abs/2512.04519)

✅[Pathwise Test-Time Correction for Autoregressive Long Video Diffusion Models](https://arxiv.org/abs/2602.05871)

✅[Progressive Autoregressive Video Diffusion Models](https://arxiv.org/abs/2410.08151)

✅[LongLive: Real-time Interactive Long Video Generation](https://arxiv.org/abs/2509.22622)

✅[NOVA: Autoregressive Video Generation without Vector Quantization](https://arxiv.org/abs/2503.18723)


## Memory Consistency

*   ### Static Memory
    

❌️🌟(w/ Pose FOV overlap retrieval Memory)[Context as Memory: Scene-Consistent Interactive Long Video Generation with Memory Retrieval](https://arxiv.org/abs/2506.03141)

✅[VMem: Consistent Interactive Video Scene Generation with Surfel-Indexed View Memory](https://arxiv.org/abs/2506.18903)

❌️[Video World Models with Long-term Spatial Memory](https://arxiv.org/abs/2506.05284)

✅[StableWorld: Towards Stable and Consistent Long Interactive Video Generation](https://arxiv.org/abs/2601.15281)

✅🌟(w/o Pose Memory)[Infinite-World: Scaling Interactive World Models to 1000-Frame Horizons via Pose-Free Hierarchical Memory](https://arxiv.org/abs/2602.02393)

✅[AnchorWeave: World-Consistent Video Generation with Retrieved Local Spatial Memories](https://arxiv.org/abs/2602.14941)

✅[Learning World Models for Interactive Video Generation](https://arxiv.org/abs/2505.21996)

❌️[Memory Forcing: Spatio-Temporal Memory for Consistent Scene Generation on Minecraft](https://arxiv.org/abs/2510.03198)

✅[DeepVerse: 4D Autoregressive Video Generation as a World Model](https://arxiv.org/abs/2506.01103)

✅[WorldMem: Long-term Consistent World Simulation with Memory](https://arxiv.org/abs/2504.12369)

❌️[MosaicMem: Hybrid Spatial Memory for Controllable Video World Models](https://arxiv.org/abs/2603.17117)

*   ### Dynamic Memory
    

✅🌟(First out-of-view Dynamic Memory)[Flow Equivariant World Models: Structured Dynamics Outside the Field of View](https://arxiv.org/abs/2601.01075)

✅🌟(First out-of-view Event Dynamic Memory)[LiveWorld: Simulating Out-of-Sight Dynamics in Generative Video World Models](https://arxiv.org/abs/2603.07145)

✅🌟(First multiplayer Minecraft World Model)[Solaris: Building a Multiplayer Video World Model in Minecraft](https://arxiv.org/abs/2602.22208)

✅[MultiWorld: Scalable Multi-Agent Multi-View Video World Models](https://arxiv.org/abs/2604.18564)

✅[Out of Sight but Not Out of Mind: Hybrid Memory for Dynamic Video World Models](https://arxiv.org/pdf/2603.25716)

## Action Control

✅🌟(Transferable skills)[Olaf-World: Orienting Latent Actions for Video World Modeling](https://arxiv.org/abs/2602.10104)

✅🌟(No longer limited to fixed controls)[AdaWorld: Learning Adaptable World Models with Latent Actions](https://arxiv.org/abs/2503.18938)

❌️🌟(Action control from games)[GameFactory: Creating New Games with Generative Interactive Videos](https://arxiv.org/abs/2501.08325)


## Interactive

✅🌟(Edit objects: add/remove/recolor)[Spatia: Video Generation with Updatable Spatial Memory](https://arxiv.org/abs/2512.15716)

❌️🌟(Text interaction: spawn weapons, affect environment)[Hunyuan-GameCraft-2: Instruction-following Interactive Game World Model](https://arxiv.org/abs/2511.23429)



## Post-Training

✅[RLVR-World: Training World Models with Reinforcement Learning](https://arxiv.org/abs/2505.13934)

✅[WorldCompass: Reinforcement Learning for Long-Horizon World Models](https://arxiv.org/abs/2602.09022)

✅[World-R1: Reinforcing 3D Constraints for Text-to-Video Generation](https://arxiv.org/abs/2604.24764)



## Physics
✅[RealWonder: Real-Time Physical Action-Conditioned Video Generation](https://arxiv.org/abs/2603.05449)

## Evaluation
✅[Interactive World Simulator for Robot Policy Training and Evaluation](https://arxiv.org/abs/2603.08546)

## Others
✅[Vid2World: Crafting Video Diffusion Models to Interactive World Models](https://arxiv.org/abs/2505.14357)

----
## Citation
If you find this repository useful, please consider citing this list:
```bash
@misc{ye2026awesomeiwm,
    title = {Awesome-Interactive-World-Model},
    author = {Yixuan Ye and {Awesome-Interactive-World-Model Contributors}},
    journal = {GitHub repository},
    url = {https://github.com/EasonTuT/Awesome-Interactive-World-Model},
    year = {2026},
}
```
