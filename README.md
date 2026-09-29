<div align="center">
  <picture>
      <img src="./figures/phoneagent_logo.png" width="20%" style="border: none; box-shadow: none;">
  </picture>
</div >

<div align="center">

# ✨OpenPhone✨: Mobile Agentic Foundation Models for AI Phone

</div>

<div align="center">
  <img src="https://readme-typing-svg.herokuapp.com?font=Orbitron&size=24&duration=3000&pause=1000&color=00D9FF&center=true&vCenter=true&width=600&lines=Welcome+to+OpenPhone;Mobile+Agentic+Foundation+Models;AI+Phone" alt="Typing Animation" />
</div>

<div align="center">
  <img src="./demo/lightagent_demo.gif" width="800" height="400" alt="演示动画">
</div>

<div align="center">
  <div style="background: linear-gradient(135deg, #667eea 0%, #764ba2 100%); border-radius: 15px; padding: 25px; text-align: center;">
    <p>
      <a href='https://github.com/HKUDS/OpenPhone'><img src='https://img.shields.io/badge/🔥Project-Page-00d9ff?style=for-the-badge&logo=github&logoColor=white&labelColor=1a1a2e'></a>
      <a href="https://huggingface.co/datasets/hkuds/OpenPhone_dataset"><img alt="Hugging Face" src="https://img.shields.io/badge/%F0%9F%A4%97%20Hugging%20Face-Dataset-ffc107?style=for-the-badge&color=ffc107&logoColor=white&labelColor=1a1a2e"/></a>
      <a href="https://huggingface.co/hkuds/OpenPhone_model"><img alt="Hugging Face" src="https://img.shields.io/badge/%F0%9F%A4%97%20Hugging%20Face-Model-ffc107?style=for-the-badge&color=ffc107&logoColor=white&labelColor=1a1a2e"/></a>
      <a href='https://github.com/THUDM/Android-Lab'><img src='https://img.shields.io/badge/⚡Based%20on-AndroidLab-4ecdc4?style=for-the-badge&logo=lightning&logoColor=white&labelColor=1a1a2e'></a>
    </p>
    <p>
      <a href="https://github.com/HKUDS/OpenPhone/stargazers"><img src='https://img.shields.io/github/stars/HKUDS/OpenPhone?color=00d9ff&style=for-the-badge&logo=star&logoColor=white&labelColor=1a1a2e' /></a>
      <a href="./Communication.md"><img src="https://img.shields.io/badge/💬Feishu-Group-07c160?style=for-the-badge&logoColor=white&labelColor=1a1a2e"></a>
      <a href="./Communication.md"><img src="https://img.shields.io/badge/WeChat-Group-07c160?style=for-the-badge&logo=wechat&logoColor=white&labelColor=1a1a2e"></a>
      <a href=""><img src="https://img.shields.io/badge/Platform-Android%20%7C%20iOS-d3d3d3?style=for-the-badge&logo=android&logoColor=white&labelColor=1a1a2e"/></a>
      <a href="./README_CN.md"><img src="https://img.shields.io/badge/📖中文文档-e74c3c?style=for-the-badge&logo=readthedocs&logoColor=white&labelColor=1a1a2e"/></a>
      <a href='https://arxiv.org/abs/2510.22009'><img src='https://img.shields.io/badge/📄arXiv-2510.22009-ff6b6b?style=for-the-badge&logo=arxiv&logoColor=white&labelColor=1a1a2e'></a>
    </p>
  </div>
</div>

</div>

<div align="center">
  <div style="width: 100%; height: 2px; margin: 20px 0; background: linear-gradient(90deg, transparent, #00d9ff, transparent);"></div>
</div>

<div>
  <div style="background: linear-gradient(135deg, #f093fb 0%, #f5576c 100%); border-radius: 16px; padding: 28px; margin: 24px 0; box-shadow: 0 8px 32px rgba(245,87,108,0.2);">
    <h2 style="color: white; margin: 0 0 8px 0; font-size: 24px; font-weight: bold;">
      <span style="background: white; color: #f5576c; padding: 3px 14px; border-radius: 20px; font-size: 24px; font-weight: bold;">🔥 Major Update:</span>
      &nbsp;PhoneCLI — From App Interfaces To Callable Commands For Mobile Agents
    </h2>
    <p style="color: rgba(255,255,255,0.7); margin: 0 0 6px 0; font-size: 14px;">🆕 September 2026</p>
    <div align="center">
      <img src="./figures/phone_cli.png" width="80%" alt="PhoneCLI Core Flow" />
    </div>
    <div align="center">
      <img src="https://readme-typing-svg.herokuapp.com?font=Orbitron&size=20&duration=3000&pause=1000&color=00D9FF&center=true&vCenter=true&width=500&lines=CLI+that+knows,+GUI+that+sees." alt="CLI that knows, GUI that sees." style="margin: 0 0 8px 0;" />
    </div>
    <p style="color: rgba(255,255,255,0.95); margin: 0 0 16px 0; font-size: 15px; line-height: 1.7;">
      Mobile GUI agents operate through a perception–action loop: at each step they screenshot the device, invoke a vision–language model (VLM), and emit an action. It is slow, costly, and brittle — yet most of what an agent does is navigation, and everyday navigation is static, ordered, and endlessly repeated. <strong style="color: white;">PhoneCLI compiles an app's GUI navigation into callable commands</strong>, with no app-internal API, no runtime instrumentation, and no model training. Offline, PhoneCLI explores a target app from the outside and distills its screens, interactive elements, and navigation edges into a <strong style="color: white;">semantically annotated map</strong>; every screen yields one deterministic command — the replay sequence that reaches it. Online, the agent selects a command, verifies it before execution, and then executes it deterministically in <strong style="color: white;">sub-second time at zero VLM cost</strong>; open-ended interaction, and every failure of the compiled path, falls back to the embedded VLM interpreter — exactly the pure VLM agent — so <strong style="color: white;">compilation can only help</strong>.
    </p>
    <ul style="color: rgba(255,255,255,0.95); margin: 0 0 20px 0; font-size: 14px; line-height: 1.8; padding-left: 20px;">
      <li>🗺️ <strong>App Maps</strong> — BFS crawls each app, recording every screen, element, and navigation path into a structured YAML graph</li>
      <li>⚡ <strong>Macro Replay</strong> — High-frequency operations execute deterministically in sub-second time, with zero VLM cost</li>
      <li>🧠 <strong>Smart Fallback</strong> — When a task doesn't match any macro, the agent gracefully degrades to VLM reasoning</li>
      <li>📦 <strong>8 Pre-Built Maps</strong> — 微博, foodpanda, Calendar, 京东, Dianping, 小红书, Music, Settings — ready to use</li>
      <li>🔗 <strong>Cross-App Planner</strong> — Multi-app tasks automatically decomposed into single-app subtasks</li>
      <li>🧪 <strong>AndroidLab Evaluation</strong> — the same idea benchmarked on the official AndroidLab suite (9 apps / 138 tasks), with a compiled app map for every app and a pure-VLM baseline for a like-for-like comparison</li>
    </ul>
    <p style="margin: 0;">
      <a href="./phonecli/README.md" style="background: white; color: #f5576c; padding: 10px 24px; border-radius: 8px; text-decoration: none; font-weight: bold; font-size: 14px;">📖 Full iOS Real-Device Documentation →</a>
      &nbsp;&nbsp;
      <a href="./phonecli_android/README.md" style="background: white; color: #f5576c; padding: 10px 24px; border-radius: 8px; text-decoration: none; font-weight: bold; font-size: 14px;">🧪 AndroidLab Evaluation Docs →</a>
      &nbsp;&nbsp;
      <a href="#-phonecli-from-app-interfaces-to-callable-commands-for-mobile-agents" style="background: rgba(255,255,255,0.15); color: white; padding: 10px 24px; border-radius: 8px; text-decoration: none; font-weight: bold; font-size: 14px; border: 1px solid rgba(255,255,255,0.35);">Read More ↓</a>
    </p>
    <p style="margin: 16px 0 0 0; color: rgba(255,255,255,0.95); font-size: 14px;">
      📄 <strong style="color: white;">PhoneCLI paper</strong> — read the full write-up on arXiv:
      <a href="https://arxiv.org/abs/2609.35671"><img src="https://img.shields.io/badge/📄arXiv-2609.35671-ff6b6b?style=for-the-badge&logo=arxiv&logoColor=white&labelColor=1a1a2e" alt="arXiv 2609.35671" /></a>
    </p>
  </div>
</div>

## 📖 Table of Contents
- [🎯 What is OpenPhone?](#-what-is-openphone)
  - [🤔 Why 3B Parameters?](#-why-3b-parameters)
  - [💡 Research Highlights](#-research-highlights)
    - [🔍 OpenPhone‑3B: Lightweight Agentic Model](#-openphone3b-lightweight-agentic-model)
    - [Why 3B is the Sweet Spot for Phone Agents](#why-3b-is-the-sweet-spot-for-phone-agents)
  - [🚀 Model Release \& Resources](#-model-release--resources)
    - [📦 Ready-to-Deploy Model](#-ready-to-deploy-model)
    - [🛠️ Complete Training Pipeline](#️-complete-training-pipeline)
  - [🚀 Quick Start](#-quick-start)
    - [📱 AndroidLab Benchmark Setup](#-androidlab-benchmark-setup)
    - [🚀 Model Deployment \& Inference](#-model-deployment--inference)
    - [⚙️ Pre-Testing Configuration](#️-pre-testing-configuration)
  - [🖥️ PhoneCLI: From App Interfaces To Callable Commands For Mobile Agents](#-phonecli-from-app-interfaces-to-callable-commands-for-mobile-agents)
    - [The Core Idea](#the-core-idea)
    - [How It Works](#how-it-works)
    - [Why This Matters](#why-this-matters)
    - [Get Started](#get-started)
  - [🌟 Key Features of OpenPhone](#-key-features-of-openphone)
    - [🤖 Lightweight Agentic Foundation Models](#-lightweight-agentic-foundation-models)
    - [☁️ Device-Cloud Collaboration Framework](#️-device-cloud-collaboration-framework)
    - [🎯 Comprehensive Mobile Agent Evaluation Playground](#-comprehensive-mobile-agent-evaluation-playground)
  - [🌟 Technical Innovation \& Implementation](#-technical-innovation--implementation)
    - [🧠 Model Training: SFT+RL](#-model-training-sftrl)
    - [☁️ Device-Cloud Collaboration Framework](#️-device-cloud-collaboration-framework-1)
    - [💾 Efficient Memory Mechanism for Mobile Agents](#-efficient-memory-mechanism-for-mobile-agents)
  - [🧪 Testing \& Evaluation](#-testing--evaluation)
    - [Single Task Testing](#single-task-testing)
    - [Batch Evaluation Scripts](#batch-evaluation-scripts)
    - [Additional App Documentation](#additional-app-documentation)
  - [📊 Result Generation](#-result-generation)
    - [LLM Evaluator Setup](#llm-evaluator-setup)
    - [Generate Evaluation Results](#generate-evaluation-results)
    - [Batch Testing File Management](#batch-testing-file-management)
  - [🎯 📊 Key Evaluation Findings for OpenPhone](#--key-evaluation-findings-for-openphone)
    - [🏆 Small Model, Big Performance](#-small-model-big-performance)
    - [🥊 Competitive Performance](#-competitive-performance)
    - [🔄 Device-Cloud Framework Works](#-device-cloud-framework-works)
    - [🧠 Longer Prompts Don't Always Help](#-longer-prompts-dont-always-help)
  - [📈 Device-Cloud Distribution Analysis for Phone Agents](#-device-cloud-distribution-analysis-for-phone-agents)
    - [📊 Workload Distribution](#-workload-distribution)
    - [💰 Efficiency Gains](#-efficiency-gains)
    - [🎯 Model Capability Impact](#-model-capability-impact)
  - [⚡ Inference Speed Comparison](#-inference-speed-comparison)
    - [🎯 Speed Advantage](#-speed-advantage)
    - [📊 Quantified Comparison](#-quantified-comparison)
    - [💡 Practical Implications](#-practical-implications)
  - [🌟 Citation](#-citation)
  - [🔗 Related Projects](#-related-projects)
  - [📜 License](#-license)

## 🎯 What is OpenPhone?

**The Problem**: Most AI agents rely on expensive cloud APIs and large models that are impractical for real-world on-device deployment. Users face **Privacy Concerns**, **Latency Issues**, and **High Costs** when their phone needs to call external services for every interaction.

**Our Solution**: OpenPhone introduces the first **Open-Source, 3B-parameter Agentic Foundation Model** designed specifically for on-device smartphone interaction. This compact vision-language model runs entirely locally — meaning **No Privacy Concerns**, **No Cloud Dependence**, and **Zero API Costs**.

## 🤔 Why 3B Parameters?
We believe the future of mobile AI lies not only in making models larger, but in making them smarter and more efficient for real-world constraints. Our 3B model is:
- ⚡ **Edge-Optimized**: Efficient enough for commodity GPUs and next-generation mobile NPUs.
- 🔒 **Privacy-First**: All computation stays on your device.
- 💰 **Cost-Free**: No cloud inference and no ongoing API fees.
- 🎯 **High-Performance**: Achieves performance comparable to 7B–9B models through advanced training.

---

## 💡 Research Highlights

### 🔍 OpenPhone‑3B: Lightweight Agentic Model
Considering the compute limitations of today’s edge devices, models with **≤3B parameters** strike a practical balance between capability and deployability. Based on this insight, we introduce **OpenPhone‑3B**, a lightweight yet powerful on‑device agent model.

- **Model Size & Architecture**: Vision-language model engineered for efficient on-device reasoning under tight mobile compute constraints.
- **Edge-Native Design**: Primary local agent compatible with consumer GPUs and mobile NPUs, eliminating continuous cloud dependency.
- **GUI‑Aware Action Capabilities**: Trained for visual interpretation, instruction following, and structured action generation across real mobile tasks.
- **Open‑Source Release**: Full model weights, configurations, and inference stack enabling community deployment and development.
- **Practical Sweet Spot**: 3B scale delivers optimal balance—significantly stronger than tiny models while remaining deployable where larger models fail.

### Why 3B is the Sweet Spot for Phone Agents
- **Hardware Fit**: 3B parameters align perfectly with consumer GPU memory (8-12GB) and emerging mobile NPU computational budgets.
- **Speed Advantage**: 3B models deliver 3-5x faster inference than 7B alternatives while maintaining competitive accuracy for sub-second GUI responses.
- **Power Efficiency**: Smaller footprint extends battery life - essential for mobile deployment where power consumption affects user experience.
- **Privacy-First**: Enables phone tasks to run entirely on-device, preserving user privacy while eliminating network dependencies.
- **Cost Savings**: Local processing eliminates expensive cloud APIs and per-request charges for sustainable operation.

---

## 🚀 Model Release & Resources

### 📦 Ready-to-Deploy Model

- **Model Weights**: OpenPhone-3B is available on [Hugging Face](https://huggingface.co/hkuds/OpenPhone_model) with full licensing for research and commercial use.
- **Production-Ready Serving**: Pre-configured vLLM inference scripts enable efficient deployment with optimized throughput and memory usage.

### 🛠️ Complete Training Pipeline
- **Reproducible Recipe**: Full training implementation including our novel two-stage approach (SFT + GRPO-style RL with synthetic GUI data).
- **Customization Support**: Detailed documentation in model_training/ allows researchers to adapt the model for domain-specific phone tasks or extend to new mobile platforms.
- **Data Generation Paradigm**: Scripts and methodologies for creating high-quality training data at scale.

## 🚀 Quick Start
This project comprises core components designed for comprehensive mobile agent development and evaluation:

- 🖥️ For the **phone agent CLI**, check out [phonecli](./phonecli/README.md) — build app maps and run autonomous tasks on iOS devices.
- ⚡ For **model training**, please refer to the training guide [README](./model_training/README.md) for comprehensive setup and execution instructions.
- 🔧 For the **data generation pipeline**, please refer to the data preparation guide [README](./prepare_data/README.md) for detailed implementation steps.

Below, we focus on evaluation using the AndroidLab benchmark framework.

### 📱 AndroidLab Benchmark Setup
Installation: Follow the official AndroidLab documentation [AndroidLab](https://github.com/THUDM/Android-Lab) for complete setup instructions.<br>

**Environment Configuration**:
- Recommended Mode: AVD on Mac (arm64) - validated in our experiments.<br>
- App Setup: Manual installation and task-specific configuration required.<br>
- Compatibility Note: Original Docker images are not compatible with AVD environments.<br>

### 🚀 Model Deployment & Inference
**vLLM Integration**:
- Inference scripts available in ./vllm_script/ directory<br>
- Optimized for efficient small model serving<br>

**Model Access**:
- OpenPhone Weights: 3B parameter model hosted on [HuggingFace](https://huggingface.co/hkuds/OpenPhone_model)<br>
- Deployment Process: Download weights → Deploy via vLLM → Configure inference service<br>
- Service Ready: Seamless integration with evaluation pipeline<br>

### ⚙️ Pre-Testing Configuration
- API Setup Required: Configure cloud model credentials in ./evaluation/evaluation.py: Line 63, Line 75, Line 81<br>
- Coming Soon: Streamlined configuration interface in development<br>

---

## 🖥 PhoneCLI: From App Interfaces To Callable Commands For Mobile Agents

### The Core Idea

Think about how you use your phone. Turning on Wi-Fi, checking today's calendar,
searching for a contact — these are **repetitive fixed sequences** you execute
dozens of times. Doing them through VLM-driven GUI interaction is slow (2–5s per
step), expensive (every screenshot costs an API call), and fragile (VLMs
hallucinate coordinates).

**PhoneCLI** takes a different approach. Instead of treating every task as a
novel GUI exploration, it **pre-builds a navigation graph (app map) for each
app**, then replays routine operations as deterministic macros. The VLM only
gets called when genuinely needed — for novel tasks, verification, or
cross-app reasoning.

### How It Works

**1. Build an app map** — A BFS crawler systematically explores every screen of
an app via WebDriverAgent, recording all tappable elements, their coordinates,
and the navigation paths between screens. Each element is classified (stable vs.
dynamic) and enriched with semantic metadata by an LLM.

```yaml
# The app map encodes every screen as a node, every element as an edge
screens:
  - id: screen_0
    description: "Settings main page"
    elements:
      - text: Wi-Fi
        center: [0.50, 0.15]      # normalized coordinates
        fixed: true                 # stable across app updates
        leads_to: screen_1          # where this tap navigates

screen_macros:
  screen_1: [force_stop, launch, tap(195, 126)]  # exact replay sequence
```

**2. Run a task** — The agent maps a natural language task to a specific macro
operation, replays it deterministically, then optionally verifies with a single
VLM screenshot check. Most routine tasks complete with **0–1 VLM calls**.

**3. Handle the unexpected** — When a task doesn't match any macro (e.g. "Find
restaurants near me that are open late"), the agent falls back to pure VLM
reasoning. The system gracefully degrades to GUI mode only when needed.

### Why This Matters

The intuition is simple: **don't ask a VLM to re-discover what you already
know**. Pre-compute the navigation graph once, then replay it reliably forever.
This is the same principle that makes CLI tools faster than GUI — applied to
phone automation.

### Get Started

```bash
# 1. Build a map for any iOS app (~10 minutes, one-time)
python phonecli/cli.py macro auto-build -b com.apple.Preferences -a Settings

# 2. Run a task
python phonecli/run.py --task "Turn on airplane mode"

# 3. Interactive daemon (continuous multi-task session)
python phonecli/run.py --interactive
```

The package ships with **pre-built maps for 8 apps** (微博, foodpanda,
Calendar, 京东, Dianping, 小红书, Music, Settings), each covering 20–50 screens
and hundreds of elements.

➜ **[Full iOS real-device documentation](./phonecli/README.md)** — setup, WebDriverAgent,
app map building, CLI reference, troubleshooting.

➜ **[AndroidLab evaluation documentation](./phonecli_android/README.md)** — the official
AndroidLab benchmark (9 apps / 138 tasks), compiled app maps, the macro agent and its
pure-VLM baseline, and judging.

---

## 🌟 Key Features of OpenPhone

### 🤖 Lightweight Agentic Foundation Models
• **Compact Architecture**: Specialized **3B-scale** Vision-Language Models optimized for mobile GUI tasks with minimal computational footprint.<br>
• **On-Device Deployment**: True smartphone-compatible models that maintain competitive performance while running locally without cloud dependency.

### ☁️ Device-Cloud Collaboration Framework
• **Dynamic Orchestration**: Real-time task complexity assessment that intelligently switches between device and cloud models based on execution requirements. <br>
• **Cost-Performance Optimization**: Strategic resource allocation that leverages cost-efficient on-device models while compensating limitations through selective cloud model usage.

### 🎯 Comprehensive Mobile Agent Evaluation Playground
• **Extended Benchmark Suite**: Beyond AndroidLab, incorporating 25+ additional tasks across popular mobile applications for real-world validation. <br>
• **Multi-Dimensional Assessment**: Comprehensive evaluation covering performance metrics, computational efficiency, and practical deployment scenarios.

---

## 🌟 Technical Innovation & Implementation

### 🧠 Model Training: SFT+RL
• **Synthetic Data Generation**: Leverages advanced MLLMs to create high-quality reasoning chain training data, addressing the scarcity of manual annotations. <br>
• **Two-Stage Training**: SFT injects GUI foundational knowledge, while GRPO reinforcement learning optimizes task completion accuracy. <br>
• **Small Model Enhancement**: Enables 3B models to achieve performance comparable to 7B-9B models on GUI tasks through structured training. 

### ☁️ Device-Cloud Collaboration Framework
• **Dynamic Task Assessment**: Real-time complexity evaluation determines when and how frequently to monitor device model performance. <br>
• **Intelligent Orchestration**: Seamlessly switches between device and cloud models based on execution progress and failure patterns. <br>
• **Cost-Performance Optimization**: Reduces cloud invocations by ~10% while maintaining high task success rates through strategic resource allocation.

### 💾 Efficient Memory Mechanism for Mobile Agents
• **Long-Horizon Reasoning**: Multi-step chain-of-thought reasoning with reflective error correction to enhance decision-making capabilities. <br>
• **Text-Based Summarization**: Compresses high-resolution screenshots into compact textual representations for efficient memory management. <br>
• **Structured Context Retention**: Maintains 10-20 steps of historical context in resource-constrained environments through optimized token usage.

---

<img src="./figures/model_large.png" style="zoom:100%;" />

---

## 🧪 Testing & Evaluation

### Single Task Testing
Test individual tasks using the following command structure:

```bash
python eval.py -n test_name -c your path to config.yaml --task_id task_id
```

Example Usage:

```bash
python eval.py -n all_cloud_v1_hyper -c ./configs/example_xml_cloud_hyper.yaml --task_id zoom_1
```

### Batch Evaluation Scripts
Convenient batch testing scripts are available in `./test_script`:

• `all_test_cloud_v1_hyper.sh`: Evaluates all 138 AndroidLab benchmark tasks<br>
• `all_test_cloud_v1_hyper_add.sh`: Evaluates tasks for four additional mobile apps<br>

### Additional App Documentation
For comprehensive details about the four additional app tasks, refer to the documentation: [Additional Apps Documentation](./docs/new_apps.md)

---

## 📊 Result Generation

### LLM Evaluator Setup
Required Configuration: Set up LLM service credentials in ./evaluation/tasks/llm_evaluator.py:

• Line 10: API configuration<br>
• Line 12: Service URL<br>

💡 Enhancement: Our implementation replaces AndroidLab's rule-based evaluation with LLM-powered assessment, providing more nuanced and accurate task completion evaluation.

### Generate Evaluation Results
Execute result generation with the following command:

```bash
python generate_result.py --input_folder ./logs/evaluation/ --output_folder ./logs/evaluation/ --output_excel ./logs/evaluation/test_name.xlsx
```
### Batch Testing File Management
⚠️ Important: When using batch scripts from ./test_script/:<br>
• Manual Transfer Required: Move generated evaluation files from script directory to ./logs/<br>
• Then Execute: Run the result generation command above<br>
• Error Prevention: This step prevents file path conflicts and ensures proper result compilation<br>

---

## 🎯 📊 Key Evaluation Findings for OpenPhone

### 🏆 Small Model, Big Performance
- **Size vs Performance**: OpenPhone-3B achieves performance comparable to 9B models while maintaining the deployment advantages of a compact architecture.
- **Efficiency Champion**: Establishes itself as a genuine "small powerhouse" that challenges the bigger-is-better assumption in mobile AI.

### 🥊 Competitive Performance
- **Against Proprietary Models**: OpenPhone-3B shows respectable performance compared to lightweight versions of proprietary models when evaluated on standard benchmarks.
- **Potential of Small Models**: Demonstrates promising results that validate the viability of compact open-source approaches in mobile agent development.

### 🔄 Device-Cloud Framework Works
- **Performance with Efficiency**: OpenPhone's hybrid architecture delivers near-optimal performance while dramatically reducing cloud model usage.
- **Intelligent Routing**: Proves that smart task routing creates practical efficiency gains without sacrificing capability.

### 🧠 Longer Prompts Don't Always Help
- **Context Matters**: Extended prompting strategies only improve performance when paired with sufficiently capable cloud models.
- **Smart Matching**: Highlights the importance of matching reasoning complexity to model capability rather than assuming longer prompts always help.

<p align="center">
  <img src="./figures/three_subplots_corrected.png" width="90%"/>
</p>

## 📈 Device-Cloud Distribution Analysis for Phone Agents

To evaluate the practical efficiency of our hybrid approach, we measured key metrics across different MLLMs: average total steps per task, the proportion of steps handled by on-device versus cloud models, and cloud call reduction compared to cloud-only baselines.

### 📊 Workload Distribution
Cloud models still handle approximately 65% of execution steps, reflecting the computational limitations of smaller on-device models for complex reasoning tasks.

### 💰 Efficiency Gains
Introducing on-device processing achieves roughly 10% reduction in cloud API calls, translating to direct cost savings and reduced latency.

### 🎯 Model Capability Impact
Advanced cloud models like GLM-4.5V show smaller reductions in cloud dependency, as their superior capabilities enable more independent task completion without requiring on-device assistance.

<p align="center">
  <img src="./figures/device_cloud_per.png" width="49%"/>
  <img src="./figures/device_cloud_reduce.png" width="47%"/>
</p>

## ⚡ Inference Speed Comparison
We evaluated average inference time per step using vLLM across different GPU configurations to assess real-world deployment feasibility. Note that GLM-4.1V-9B-Thinking could not operate on a single 3090 GPU due to context length constraints.

<div align="center">

| Model                  | GPUs        | Size | SR   | Time Cost / Step |
| ---------------------- | ----------- | ---- | ---- | ---------------- |
| Qwen2.5-VL-7B-Instruct | Single 3090 | 7B   | 10.1 | 6289.15 ms       |
| OpenPhone              | Single 3090 | 3B   | 15.2 | 4170.63 ms       |
| GLM-4.1V-9B-Thinking   | Two 3090s   | 9B   | 24.6 | 14584.89 ms      |
| Qwen2.5-VL-7B-Instruct | Two 3090s   | 7B   | 10.1 | 4587.79 ms       |
| OpenPhone              | Two 3090s   | 3B   | 15.2 | 3524.25 ms       |

</div>

### 🎯 Speed Advantage
- **Clear Winner**: OpenPhone demonstrates significant inference speed advantages thanks to its lightweight 3B architecture
- **Real-World Ready**: Speed benefits become increasingly pronounced under constrained computational resources, matching typical edge deployment scenarios

### 📊 Quantified Comparison
- **3.5x Faster**: OpenPhone on single 3090 vs GLM-4.1V-9B-Thinking on dual 3090s.
- **4x Faster**: OpenPhone on dual 3090s vs GLM-4.1V-9B-Thinking on dual 3090s.
- **OpenPhone's Lightweight**: GLM-4.1V-9B-Thinking's inability to run on single 3090 severely limits edge deployment options.

### 💡 Practical Implications
The trade-off is clear: while larger models like GLM-4.1V-9B-Thinking achieve higher task performance, OpenPhone's speed advantages make it far more suitable for real-world on-device scenarios where response time and hardware constraints matter.

---

## 🌟 Citation

If you find this work helpful to your research, please kindly consider citing our paper.

```
@inproceedings{jiang2026openphone,
  title={OpenPhone: Mobile Agentic Foundation Models},
  author={Jiang, Yangqin and Huang, Chao},
  booktitle={Findings of the Association for Computational Linguistics: ACL 2026},
  pages={30362--30380},
  year={2026}
}
```

## 🔗 Related Projects

OpenPhone builds upon excellent open-source projects. We sincerely thank their authors and contributors:

- [AndroidLab](https://github.com/THUDM/Android-Lab) - The benchmark framework.
- [R1-V](https://github.com/StarsfieldAI/R1-V) - Implementation details for the GRPO training methodology.
- [LLaMA Factory](https://github.com/hiyouga/LLaMA-Factory) - The unified training framework enabling efficient model fine-tuning.

## 📜 License

This project is released under the [MIT License](./LICENSE).

<div align="center">

**If this project helps you, please give us a Star🌟**

**🤖 Empower AI Phone with Agents!**

<br>

<p align="center">
  <em> ❤️ Thanks for visiting ✨ OpenPhone!</em><br><br>
  <img src="https://visitor-badge.laobi.icu/badge?page_id=HKUDS.OpenPhone&style=for-the-badge&color=00d4ff" alt="Views">
</p>


