# writing related work

**Output-Distribution Distillation for Contextual Sparsity Prediction in SwiGLU LLMs** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 23
- **Recorded user turns:** 0
- **Tool calls:** 7
- **Original source:** `logs/workers/worker_writing_related-work_20260516T022632.log`
- **Structured JSON:** [`fb4553bb91182ee439b4.json`](../../sessions/fb/fb4553bb91182ee439b4.json)

## Before a recorded user message

23 recorded events

### Log line

_source line 1_

Warning: no stdin data received in 3s, proceeding without it. If piping from a slow command, redirect stdin explicitly: < /dev/null to skip, or wait longer.

---

### System

_source line 2_

```json
{
  "type": "system",
  "subtype": "init",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu",
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "tools": [
    "Task",
    "AskUserQuestion",
    "Bash",
    "CronCreate",
    "CronDelete",
    "CronList",
    "Edit",
    "EnterPlanMode",
    "EnterWorktree",
    "ExitPlanMode",
    "ExitWorktree",
    "Glob",
    "Grep",
    "ListMcpResourcesTool",
    "Monitor",
    "NotebookEdit",
    "PushNotification",
    "Read",
    "ReadMcpResourceTool",
    "RemoteTrigger",
    "ScheduleWakeup",
    "Skill",
    "TaskOutput",
    "TaskStop",
    "TodoWrite",
    "ToolSearch",
    "WebFetch",
    "WebSearch",
    "Write",
    "mcp__agent-ml-research__append_idea",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__read_registry",
    "mcp__agent-ml-research__register_artifact",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__update_registry"
  ],
  "mcp_servers": [
    {
      "name": "agent-ml-research",
      "status": "connected"
    }
  ],
  "model": "claude-opus-4-6",
  "permissionMode": "bypassPermissions",
  "slash_commands": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api",
    "clear",
    "compact",
    "context",
    "heapdump",
    "init",
    "review",
    "security-review",
    "extra-usage",
    "usage",
    "insights",
    "team-onboarding"
  ],
  "apiKeySource": "none",
  "claude_code_version": "2.1.126",
  "output_style": "default",
  "agents": [
    "claude",
    "Explore",
    "general-purpose",
    "Plan",
    "statusline-setup"
  ],
  "skills": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api"
  ],
  "plugins": [],
  "analytics_disabled": false,
  "uuid": "2a21c129-7fa8-4ca6-8c1f-45887d5e06ea",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/memory/"
  },
  "fast_mode_state": "off"
}
```

---

### Runtime record

_source line 3_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed",
    "resetsAt": 1778903400,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "e0afb5c9-1967-4568-b420-f5ab019905f1",
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81"
}
```

---

### Assistant

_source line 4_

I'll start by reading the project files to get the full literature info and framing constraints.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "c3015312-0d9b-47b7-9029-f0026f5b0d62",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B9zVTej7rFmTaBFFMafxk2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12462,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12462
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 5_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_0163TeeG8KMwT99DhMuxCfon`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "f95e63f1-eca2-4958-b444-4e288df0b95a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B9zVTej7rFmTaBFFMafxk2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12462,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12462
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-16T02:26:45.951Z_

<details><summary>↩ Tool result · `toolu_0163TeeG8KMwT99DhMuxCfon`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_project_file"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "06596f53-8c9c-47b8-aea3-dea899ea3a34",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_project_file"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file",
    "total_deferred_tools": 25
  }
}
```

</details>

---

### Tool call

_source line 7_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01DaqPLTvLuz4jhZnHNYzBhn`</summary>

```json
{
  "project": "distill_sparse_swiglu",
  "file": "literature_map.yaml",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "94404c21-aa43-4209-88f4-785c9464e57b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FEX6H8w4CEpKbpFF3nowdh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 454,
      "cache_read_input_tokens": 24303,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 454
      },
      "output_tokens": 66,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-16T02:26:48.500Z_

<details><summary>↩ Tool result · `toolu_01DaqPLTvLuz4jhZnHNYzBhn`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/literature_map.yaml\", \"content\": \"# Literature Map: KL Distillation for Sparse SwiGLU Activation Prediction\\n# Last updated: 2026-05-15\\n# Survey scope: 2023-2026, 4 directions\\n\\n# =============================================================================\\n# Direction 1: KL distillation for structured/activation sparsity\\n# Finding: NO prior work uses KL to train an activation sparsity PREDICTOR.\\n# Existing predictors use BCE (DejaVu, ShadowLLM). SPON uses KL but for\\n# learnable bias correction, not predictor training. This is our novelty.\\n# =============================================================================\\n\\n- title: \\\"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\\\"\\n  authors: [Haotian Xu, Jiannan Yang, Tian Gao, Tsui-Wei Weng, Tengfei Ma]\\n  venue: ICML 2026\\n  year: 2026\\n  arxiv_id: \\\"2512.12744\\\"\\n  category: direct-competitor\\n  role: \\\"最接近的KL蒸馏用于稀疏性的工作——但SPON训练的是可学习bias项而非predictor\\\"\\n  key_finding: \\\"SPON注入input-independent learnable activation vectors作为sparse computation的anchor，用KL散度(dense vs sparse logits)做distribution matching训练，训练后吸收进bias项，零推理开销\\\"\\n  relevance_to_us: \\\"SPON证明KL divergence比BCE/MSE更适合sparsity场景的distribution matching。但SPON是全局bias correction而非per-token predictor——我们的predictor方案能实现input-dependent的sparsity pattern，比SPON更灵活。SPON在50-60% sparsity下测试，与我们目标一致\\\"\\n\\n- title: \\\"Compact Language Models via Pruning and Knowledge Distillation\\\"\\n  authors: [Saurav Muralidharan, Sharath Turuvekere Sreenivas, Raviraj Joshi, Marcin Chochowski, Mostofa Patwary, Mohammad Shoeybi, Bryan Catanzaro, Jan Kautz, Pavlo Molchanov]\\n  venue: NeurIPS 2024\\n  year: 2024\\n  arxiv_id: \\\"2407.14679\\\"\\n  category: method-component\\n  role: \\\"KL蒸馏用于结构化剪枝后恢复——验证logit-only KL优于intermediate matching\\\"\\n  key_finding: \\\"Minitron用logit-only forward KL divergence做structured pruning后的distillation recovery，发现仅用KL loss（不用CE或intermediate matching）效果最好，学生模型继承了teacher的inter-token关系和confidence calibration\\\"\\n  relevance_to_us: \\\"支持我们的核心假设：KL divergence保留output distribution比逐元素BCE更优。Minitron的发现（logit-only KL最优）为我们predictor的KL训练目标提供了理论支撑\\\"\\n\\n- title: \\\"Instruction-Following Pruning for Large Language Models\\\"\\n  authors: [Bairu Hou, Qibin Chen, Jianyu Wang, Guoli Yin, Chong Wang, Nan Du, Ruoming Pang, Shiyu Chang, Tao Lei]\\n  venue: ICML 2025\\n  year: 2025\\n  arxiv_id: \\\"2501.02086\\\"\\n  category: method-component\\n  role: \\\"训练sparse mask predictor的范式——input-dependent mask selection\\\"\\n  key_finding: \\\"训练一个sparse mask predictor以instruction为输入动态选择最相关参数子集，联合优化mask predictor和LLM\\\"\\n  relevance_to_us: \\\"架构上与我们类似（训练predictor生成mask），但目标是instruction-aware weight pruning而非activation sparsity。可参考其predictor-LLM联合优化策略\\\"\\n\\n# =============================================================================\\n# Direction 2: Output distribution preservation in pruning/sparsity\\n# =============================================================================\\n\\n- title: \\\"Distilling to Hybrid Attention Models via KL-Guided Layer Selection\\\"\\n  authors: []\\n  venue: arXiv\\n  year: 2025\\n  arxiv_id: \\\"2512.20569\\\"\\n  category: method-component\\n  role: \\\"KL散度引导layer selection——用distribution差异决定哪些层需要保留\\\"\\n  key_finding: \\\"用KL divergence作为指标选择哪些attention层替换为hybrid attention，通过最小化output distribution变化来指导架构决策\\\"\\n  relevance_to_us: \\\"方法论启示：KL divergence不仅可作为训练loss，还可作为layer-wise重要性指标。我们可用per-layer KL分析哪些层的sparsity对output distribution影响最大\\\"\\n\\n# =============================================================================\\n# Direction 3: SPON和类似的learnable bias correction for sparsity\\n# =============================================================================\\n\\n- title: \\\"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\\\"\\n  authors: [Aayush Gautam, Mukul Gagrani, Junyoung Park, Mingu Lee, Chiris Lott, Narasimha Reddy]\\n  venue: arXiv\\n  year: 2026\\n  arxiv_id: \\\"2602.00397\\\"\\n  category: direct-competitor\\n  role: \\\"Predictor + error compensation双组件架构——与SPON的bias correction思路互补\\\"\\n  key_finding: \\\"组合三个组件：(1) lightweight expert predictor选择high-importance neurons，(2) error compensation network修正sparsity误差，(3) layer-wise sparsity scheduler分配计算。50% FFN sparsity下达到1.45x prefill加速\\\"\\n  relevance_to_us: \\\"与我们的方案最可比：都用predictor做activation sparsity。我们的差异在于用KL loss训练predictor而非BCE，且不需要额外的error compensation网络（KL loss本身应该能减少distribution shift）\\\"\\n\\n- title: \\\"Amber Pruner: Leveraging N:M Activation Sparsity for Efficient Prefill in Large Language Models\\\"\\n  authors: [Tai An, Ruwu Cai, Yanzhe Zhang, Yang Liu, Hao Chen, Pengcheng Xie, Sheng Chang, Yiwu Yao, Gongyi Wang]\\n  venue: arXiv\\n  year: 2025\\n  arxiv_id: \\\"2508.02128\\\"\\n  category: background\\n  role: \\\"N:M structured activation sparsity——hardware-friendly的sparsity pattern\\\"\\n  key_finding: \\\"Training-free的top-k策略在linear projection层内确定N:M activation masks，在2:4/4:8/8:16多种ratio下有效，可与W8A8量化组合\\\"\\n  relevance_to_us: \\\"如果我们的predictor输出改为N:M structured pattern而非unstructured binary mask，可获得更好的hardware加速。值得作为future work\\\"\\n\\n# =============================================================================\\n# Direction 4: Predictor-based activation sparsity (TEAL, DejaVu, PowerInfer等)\\n# =============================================================================\\n\\n- title: \\\"Training-Free Activation Sparsity in Large Language Models\\\"\\n  authors: [James Liu, Pragaash Ponnusamy, Tianle Cai, Han Guo, Yoon Kim, Ben Athiwaratkun]\\n  venue: ICLR 2025 (Spotlight)\\n  year: 2025\\n  arxiv_id: \\\"2408.14690\\\"\\n  category: direct-competitor\\n  role: \\\"TEAL——我们的主要baseline，training-free magnitude pruning\\\"\\n  key_finding: \\\"对所有hidden states施加magnitude-based sparsity（不需训练），在40-50% sparsity下性能降低很小，Llama-2/3和Mistral 7B-70B上验证。50% sparsity下1.8x decoding加速\\\"\\n  relevance_to_us: \\\"TEAL用BCE度量sparsity mask质量（二元对错），我们的核心论点是：BCE只看neuron是否激活的对错，忽略了错误预测对output distribution的差异化影响。KL loss应该能让predictor学到'哪些neuron的错误预测对output影响更大'\\\"\\n\\n- title: \\\"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\\\"\\n  authors: [Zichang Liu, Jue Wang, Tri Dao, Tianyi Zhou, Binhang Yuan, Zhao Song, Anshumali Shrivastava, Ce Zhang, Yuandong Tian, Christopher Re, Beidi Chen]\\n  venue: ICML 2023\\n  year: 2023\\n  arxiv_id: \\\"2310.17157\\\"\\n  category: direct-competitor\\n  role: \\\"Predictor-based contextual sparsity的开创性工作——我们的直接对比对象\\\"\\n  key_finding: \\\"用两层MLP predictor预测每层的contextual sparsity pattern（哪些attention heads和MLP neurons可跳过），在OPT-175B上实现2x加速。Predictor用BCE训练\\\"\\n  relevance_to_us: \\\"DejaVu是predictor-based sparsity的baseline。其predictor用BCE训练——我们改用KL loss训练类似的predictor。关键差异：DejaVu在per-neuron level用BCE，我们在output distribution level用KL\\\"\\n\\n- title: \\\"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\\\"\\n  authors: [Yash Akhauri, Ahmed F AbouElhamayed, Jordan Dotzel, Zhiru Zhang, Alexander M Rush, Safeen Huda, Mohamed S Abdelfattah]\\n  venue: EMNLP 2024\\n  year: 2024\\n  arxiv_id: \\\"2406.16635\\\"\\n  category: direct-competitor\\n  role: \\\"DejaVu的改进——更好的predictor架构和sparsity pattern enforcement\\\"\\n  key_finding: \\\"Shadow predictor超越magnitude-based pruning，context-dependent评估attention head和neuron重要性。比DejaVu端到端精度提升15%，速度提升20%\\\"\\n  relevance_to_us: \\\"ShadowLLM改进了predictor架构但仍用BCE-style loss。我们的改进方向正交：不改predictor架构，改训练loss（BCE→KL）。两种改进可能互补\\\"\\n\\n- title: \\\"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\\\"\\n  authors: [Jiho Shin, Hoeseok Yang, Youngmin Yi]\\n  venue: DATE 2025\\n  year: 2025\\n  arxiv_id: \\\"2411.12692\\\"\\n  category: background\\n  role: \\\"Training-free sign-bit predictor——极低开销的sparsity预测\\\"\\n  key_finding: \\\"仅比较input和weight的sign bits预测activation sparsity，无需训练。仅适用于ReLU-based LLMs，不适用SwiGLU\\\"\\n  relevance_to_us: \\\"不适用于SwiGLU模型（我们的目标），但其sign-bit方法的简洁性值得参考。SwiGLU缺乏天然sparsity证明trained predictor的必要性\\\"\\n\\n- title: \\\"SVD Contextual Sparsity Predictors for Fast LLM Inference\\\"\\n  authors: [Georgii Serbin, Kirill Koshkin, Zhongao Sun, Anastasiya Bistrigova, C.C. Korikov]\\n  venue: arXiv\\n  year: 2026\\n  arxiv_id: \\\"2603.14110\\\"\\n  category: direct-competitor\\n  role: \\\"Training-free SVD-based sparsity predictor——用gate projection矩阵的SVD做预测\\\"\\n  key_finding: \\\"对ReGLU FFN的gate projection矩阵做truncation-aware SVD构建sparse pattern predictor，90% FFN sparsity下1.8x decoding加速，benchmark降低<1%\\\"\\n  relevance_to_us: \\\"虽然是training-free competitor，但focus在ReGLU（不是SwiGLU）且需要90%天然稀疏性。我们的方法在SwiGLU的50%目标sparsity下工作，使用场景不同\\\"\\n\\n- title: \\\"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\\\"\\n  authors: [Donghyun Lee, Je-Yong Lee, Genghan Zhang, Mo Tiwari, Azalia Mirhoseini]\\n  venue: arXiv\\n  year: 2024\\n  arxiv_id: \\\"2404.08763\\\"\\n  category: direct-competitor\\n  role: \\\"Contextual thresholding——不训练predictor，用统计threshold做sparsity\\\"\\n  key_finding: \\\"为每个MLP层计算SiLU(x)激活的percentile threshold做sparsification，50% sparsity下性能降低1-2%，无需fine-tuning。Mistral-7B和Llama2-7B上验证\\\"\\n  relevance_to_us: \\\"CATS直接在SwiGLU/SiLU模型上工作，是我们的直接competitor。但CATS是固定threshold不考虑input context，我们的trained predictor是input-dependent的，理论上更优\\\"\\n\\n- title: \\\"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\\\"\\n  authors: [Zhenyu Zhang, Zechun Liu, Yuandong Tian, Harshit Khaitan, Zhangyang Wang, Steven Li]\\n  venue: ICLR 2025\\n  year: 2025\\n  arxiv_id: \\\"2504.19449\\\"\\n  category: background\\n  role: \\\"Training-free rank-aware方法——利用input channel sparsity和SVD\\\"\\n  key_finding: \\\"用SVD分解将input channel sparsity映射到output，无需预测active channels。50% model-level sparsity下43%端到端加速\\\"\\n  relevance_to_us: \\\"Training-free baseline。如果R-Sparse在SwiGLU模型上效果很好，我们需要证明trained KL predictor的额外训练成本是值得的\\\"\\n\\n- title: \\\"Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\\\"\\n  authors: [Marco Federici, Davide Belli, Mart van Baalen, Amir Jalalirad, Andrii Skliar, Bence Major, Markus Nagel, Paul Whatmough]\\n  venue: MLSys 2025\\n  year: 2024\\n  arxiv_id: \\\"2412.01380\\\"\\n  category: direct-competitor\\n  role: \\\"Predictor-free dynamic pruning for SwiGLU——直接针对SwiGLU的magnitude pruning\\\"\\n  key_finding: \\\"Predictor-free方案动态剪枝SwiGLU MLP层，配合LoRA adapter恢复精度。Phi-3-Medium上46%内存减少+40%吞吐提升\\\"\\n  relevance_to_us: \\\"直接针对SwiGLU的competitor。DIP证明SwiGLU的sparsity pattern难以预测（所以放弃predictor），我们的KL-trained predictor需要证明能克服这个挑战\\\"\\n\\n# =============================================================================\\n# 补充：Activation function替换和sparsity增强\\n# =============================================================================\\n\\n- title: \\\"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\\\"\\n  authors: [Iman Mirzadeh, Keivan Alizadeh, Sachin Mehta, Carlo C Del Mundo, Oncel Tuzel, Golnoosh Samei, Mohammad Rastegari, Mehrdad Farajtabar]\\n  venue: ICLR 2024\\n  year: 2024\\n  arxiv_id: \\\"2310.04564\\\"\\n  category: background\\n  role: \\\"ReLU替换SiLU获得天然sparsity——替代路线\\\"\\n  key_finding: \\\"用ReLU替换SiLU/GELU后continual pretraining，获得天然高稀疏性（>90%），推理计算减少3x\\\"\\n  relevance_to_us: \\\"替代路线：修改activation function vs 训练predictor。我们的定位：不需要修改pretrained模型架构，作为plug-in predictor在现有SwiGLU模型上工作\\\"\\n\\n- title: \\\"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\\\"\\n  authors: [Yixin Song, Haotong Xie, Zhengyan Zhang, Bo Wen, Li Ma, Zeyu Mi, Haibo Chen]\\n  venue: arXiv\\n  year: 2024\\n  arxiv_id: \\\"2406.05955\\\"\\n  category: background\\n  role: \\\"dReLU获得90%+ sparsity——activation function工程的极致\\\"\\n  key_finding: \\\"提出dReLU使LLM达到近90% sparsity同时保持SOTA性能，2-5x decoding加速\\\"\\n  relevance_to_us: \\\"与ReLU Strikes Back同一思路但更极端。我们不改activation function，这是差异化定位\\\"\\n\\n- title: \\\"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\\\"\\n  authors: [Chenyang Song, Xu Han, Zhengyan Zhang, Shengding Hu, Xiyu Shi, Kuai Li, Chen Chen, Zhiyuan Liu, Guangli Li, Tao Yang, Maosong Sun]\\n  venue: COLING 2025\\n  year: 2025\\n  arxiv_id: \\\"2402.13516\\\"\\n  category: background\\n  role: \\\"Progressive sparsification——渐进式增加sparsity regularization\\\"\\n  key_finding: \\\"三步法：ReLU替换→progressive sparsity regularization（沿sine curve增强）→threshold shifting(FATReLU)。LLaMA2-7B达89.32% sparsity\\\"\\n  relevance_to_us: \\\"ProSparse的progressive training策略可参考：我们的KL predictor训练也可渐进式增加sparsity目标（已在Lagrangian约束中实现）\\\"\\n\\n- title: \\\"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\\\"\\n  authors: [Yuqi Luo, Chenyang Song, Xu Han, Yingfa Chen, Chaojun Xiao, Xiaojun Meng, Liqun Deng, Jiansheng Wei, Zhiyuan Liu, Maosong Sun]\\n  venue: arXiv\\n  year: 2024\\n  arxiv_id: \\\"2411.02335\\\"\\n  category: background\\n  role: \\\"Activation sparsity的scaling law——理论基础\\\"\\n  key_finding: \\\"SiLU/SwiGLU的activation ratio随训练递增（变密），ReLU递减（变稀）。Sparsity对parameter scale不敏感，与width-depth ratio线性相关\\\"\\n  relevance_to_us: \\\"理论支撑：SiLU/SwiGLU模型天然不够稀疏（随训练变密），因此需要外部predictor/pruning来获得稀疏性——这是我们工作的motivation之一\\\"\\n\\n- title: \\\"A Sparsity Predicting Approach for Large Language Models via Activation Pattern Clustering\\\"\\n  authors: [Nobel Dhar, Bobin Deng, Md Romyull Islam, Xinyue Zhang, Kazi Fahim Ahmad Nasif, Kun Suo]\\n  venue: Euro-Par 2025\\n  year: 2025\\n  arxiv_id: \\\"2507.14179\\\"\\n  category: background\\n  role: \\\"Clustering-based sparsity prediction——用聚类简化prediction\\\"\\n  key_finding: \\\"将activation patterns聚类为representative clusters，预测cluster assignment而非individual neuron states，减少prediction开销。Mistral-7B上79.34%聚类精度\\\"\\n  relevance_to_us: \\\"降低predictor复杂度的思路。如果我们的per-neuron KL predictor开销太大，可考虑cluster-level prediction\\\"\\n\\n# =============================================================================\\n# 竞争格局总结\\n# =============================================================================\\n#\\n# 我们的独特定位:\\n# 1. 唯一使用KL divergence训练activation sparsity predictor的工作\\n#    - DejaVu/ShadowLLM用BCE训练predictor\\n#    - SPON用KL但训练bias correction而非predictor\\n#    - TEAL/CATS/R-Sparse/SparseInfer/SVD-CSP是training-free\\n# 2. 专注SwiGLU模型的50% sparsity目标\\n#    - ReLU/dReLU方案需要替换activation function\\n#    - 很多training-free方案在SwiGLU上效果不佳(DIP论文证实)\\n# 3. 通过保留output distribution(而非逐neuron匹配)来指导sparsity\\n#    - Minitron/SPON已证明KL loss优于MSE/BCE做distribution matching\\n#    - 我们将此insight应用到predictor训练\\n#\\n# 主要related work定位:\\n# - vs TEAL: trained predictor(input-dependent) vs fixed magnitude threshold\\n# - vs DejaVu/ShadowLLM: KL loss vs BCE loss训练predictor\\n# - vs SPON: predictor vs learnable bias; 都用KL但目标不同\\n# - vs DIP: trained predictor vs predictor-free pruning\\n# - vs ReLU/TurboSparse/ProSparse: 不改activation function\\n# - vs Fast Forward: KL loss vs BCE+error compensation\\n# - vs CATS: input-dependent predictor vs fixed percentile threshold\\n\", \"total_chars\": 13950, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "7fb77961-6d39-4872-923a-a75ff959105e",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/literature_map.yaml\\\", \\\"content\\\": \\\"# Literature Map: KL Distillation for Sparse SwiGLU Activation Prediction\\\\n# Last updated: 2026-05-15\\\\n# Survey scope: 2023-2026, 4 directions\\\\n\\\\n# =============================================================================\\\\n# Direction 1: KL distillation for structured/activation sparsity\\\\n# Finding: NO prior work uses KL to train an activation sparsity PREDICTOR.\\\\n# Existing predictors use BCE (DejaVu, ShadowLLM). SPON uses KL but for\\\\n# learnable bias correction, not predictor training. This is our novelty.\\\\n# =============================================================================\\\\n\\\\n- title: \\\\\\\"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\\\\\\\"\\\\n  authors: [Haotian Xu, Jiannan Yang, Tian Gao, Tsui-Wei Weng, Tengfei Ma]\\\\n  venue: ICML 2026\\\\n  year: 2026\\\\n  arxiv_id: \\\\\\\"2512.12744\\\\\\\"\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"最接近的KL蒸馏用于稀疏性的工作——但SPON训练的是可学习bias项而非predictor\\\\\\\"\\\\n  key_finding: \\\\\\\"SPON注入input-independent learnable activation vectors作为sparse computation的anchor，用KL散度(dense vs sparse logits)做distribution matching训练，训练后吸收进bias项，零推理开销\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"SPON证明KL divergence比BCE/MSE更适合sparsity场景的distribution matching。但SPON是全局bias correction而非per-token predictor——我们的predictor方案能实现input-dependent的sparsity pattern，比SPON更灵活。SPON在50-60% sparsity下测试，与我们目标一致\\\\\\\"\\\\n\\\\n- title: \\\\\\\"Compact Language Models via Pruning and Knowledge Distillation\\\\\\\"\\\\n  authors: [Saurav Muralidharan, Sharath Turuvekere Sreenivas, Raviraj Joshi, Marcin Chochowski, Mostofa Patwary, Mohammad Shoeybi, Bryan Catanzaro, Jan Kautz, Pavlo Molchanov]\\\\n  venue: NeurIPS 2024\\\\n  year: 2024\\\\n  arxiv_id: \\\\\\\"2407.14679\\\\\\\"\\\\n  category: method-component\\\\n  role: \\\\\\\"KL蒸馏用于结构化剪枝后恢复——验证logit-only KL优于intermediate matching\\\\\\\"\\\\n  key_finding: \\\\\\\"Minitron用logit-only forward KL divergence做structured pruning后的distillation recovery，发现仅用KL loss（不用CE或intermediate matching）效果最好，学生模型继承了teacher的inter-token关系和confidence calibration\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"支持我们的核心假设：KL divergence保留output distribution比逐元素BCE更优。Minitron的发现（logit-only KL最优）为我们predictor的KL训练目标提供了理论支撑\\\\\\\"\\\\n\\\\n- title: \\\\\\\"Instruction-Following Pruning for Large Language Models\\\\\\\"\\\\n  authors: [Bairu Hou, Qibin Chen, Jianyu Wang, Guoli Yin, Chong Wang, Nan Du, Ruoming Pang, Shiyu Chang, Tao Lei]\\\\n  venue: ICML 2025\\\\n  year: 2025\\\\n  arxiv_id: \\\\\\\"2501.02086\\\\\\\"\\\\n  category: method-component\\\\n  role: \\\\\\\"训练sparse mask predictor的范式——input-dependent mask selection\\\\\\\"\\\\n  key_finding: \\\\\\\"训练一个sparse mask predictor以instruction为输入动态选择最相关参数子集，联合优化mask predictor和LLM\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"架构上与我们类似（训练predictor生成mask），但目标是instruction-aware weight pruning而非activation sparsity。可参考其predictor-LLM联合优化策略\\\\\\\"\\\\n\\\\n# =============================================================================\\\\n# Direction 2: Output distribution preservation in pruning/sparsity\\\\n# =============================================================================\\\\n\\\\n- title: \\\\\\\"Distilling to Hybrid Attention Models via KL-Guided Layer Selection\\\\\\\"\\\\n  authors: []\\\\n  venue: arXiv\\\\n  year: 2025\\\\n  arxiv_id: \\\\\\\"2512.20569\\\\\\\"\\\\n  category: method-component\\\\n  role: \\\\\\\"KL散度引导layer selection——用distribution差异决定哪些层需要保留\\\\\\\"\\\\n  key_finding: \\\\\\\"用KL divergence作为指标选择哪些attention层替换为hybrid attention，通过最小化output distribution变化来指导架构决策\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"方法论启示：KL divergence不仅可作为训练loss，还可作为layer-wise重要性指标。我们可用per-layer KL分析哪些层的sparsity对output distribution影响最大\\\\\\\"\\\\n\\\\n# =============================================================================\\\\n# Direction 3: SPON和类似的learnable bias correction for sparsity\\\\n# =============================================================================\\\\n\\\\n- title: \\\\\\\"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\\\\\\\"\\\\n  authors: [Aayush Gautam, Mukul Gagrani, Junyoung Park, Mingu Lee, Chiris Lott, Narasimha Reddy]\\\\n  venue: arXiv\\\\n  year: 2026\\\\n  arxiv_id: \\\\\\\"2602.00397\\\\\\\"\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"Predictor + error compensation双组件架构——与SPON的bias correction思路互补\\\\\\\"\\\\n  key_finding: \\\\\\\"组合三个组件：(1) lightweight expert predictor选择high-importance neurons，(2) error compensation network修正sparsity误差，(3) layer-wise sparsity scheduler分配计算。50% FFN sparsity下达到1.45x prefill加速\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"与我们的方案最可比：都用predictor做activation sparsity。我们的差异在于用KL loss训练predictor而非BCE，且不需要额外的error compensation网络（KL loss本身应该能减少distribution shift）\\\\\\\"\\\\n\\\\n- title: \\\\\\\"Amber Pruner: Leveraging N:M Activation Sparsity for Efficient Prefill in Large Language Models\\\\\\\"\\\\n  authors: [Tai An, Ruwu Cai, Yanzhe Zhang, Yang Liu, Hao Chen, Pengcheng Xie, Sheng Chang, Yiwu Yao, Gongyi Wang]\\\\n  venue: arXiv\\\\n  year: 2025\\\\n  arxiv_id: \\\\\\\"2508.02128\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"N:M structured activation sparsity——hardware-friendly的sparsity pattern\\\\\\\"\\\\n  key_finding: \\\\\\\"Training-free的top-k策略在linear projection层内确定N:M activation masks，在2:4/4:8/8:16多种ratio下有效，可与W8A8量化组合\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"如果我们的predictor输出改为N:M structured pattern而非unstructured binary mask，可获得更好的hardware加速。值得作为future work\\\\\\\"\\\\n\\\\n# =============================================================================\\\\n# Direction 4: Predictor-based activation sparsity (TEAL, DejaVu, PowerInfer等)\\\\n# =============================================================================\\\\n\\\\n- title: \\\\\\\"Training-Free Activation Sparsity in Large Language Models\\\\\\\"\\\\n  authors: [James Liu, Pragaash Ponnusamy, Tianle Cai, Han Guo, Yoon Kim, Ben Athiwaratkun]\\\\n  venue: ICLR 2025 (Spotlight)\\\\n  year: 2025\\\\n  arxiv_id: \\\\\\\"2408.14690\\\\\\\"\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"TEAL——我们的主要baseline，training-free magnitude pruning\\\\\\\"\\\\n  key_finding: \\\\\\\"对所有hidden states施加magnitude-based sparsity（不需训练），在40-50% sparsity下性能降低很小，Llama-2/3和Mistral 7B-70B上验证。50% sparsity下1.8x decoding加速\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"TEAL用BCE度量sparsity mask质量（二元对错），我们的核心论点是：BCE只看neuron是否激活的对错，忽略了错误预测对output distribution的差异化影响。KL loss应该能让predictor学到'哪些neuron的错误预测对output影响更大'\\\\\\\"\\\\n\\\\n- title: \\\\\\\"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\\\\\\\"\\\\n  authors: [Zichang Liu, Jue Wang, Tri Dao, Tianyi Zhou, Binhang Yuan, Zhao Song, Anshumali Shrivastava, Ce Zhang, Yuandong Tian, Christopher Re, Beidi Chen]\\\\n  venue: ICML 2023\\\\n  year: 2023\\\\n  arxiv_id: \\\\\\\"2310.17157\\\\\\\"\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"Predictor-based contextual sparsity的开创性工作——我们的直接对比对象\\\\\\\"\\\\n  key_finding: \\\\\\\"用两层MLP predictor预测每层的contextual sparsity pattern（哪些attention heads和MLP neurons可跳过），在OPT-175B上实现2x加速。Predictor用BCE训练\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"DejaVu是predictor-based sparsity的baseline。其predictor用BCE训练——我们改用KL loss训练类似的predictor。关键差异：DejaVu在per-neuron level用BCE，我们在output distribution level用KL\\\\\\\"\\\\n\\\\n- title: \\\\\\\"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\\\\\\\"\\\\n  authors: [Yash Akhauri, Ahmed F AbouElhamayed, Jordan Dotzel, Zhiru Zhang, Alexander M Rush, Safeen Huda, Mohamed S Abdelfattah]\\\\n  venue: EMNLP 2024\\\\n  year: 2024\\\\n  arxiv_id: \\\\\\\"2406.16635\\\\\\\"\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"DejaVu的改进——更好的predictor架构和sparsity pattern enforcement\\\\\\\"\\\\n  key_finding: \\\\\\\"Shadow predictor超越magnitude-based pruning，context-dependent评估attention head和neuron重要性。比DejaVu端到端精度提升15%，速度提升20%\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"ShadowLLM改进了predictor架构但仍用BCE-style loss。我们的改进方向正交：不改predictor架构，改训练loss（BCE→KL）。两种改进可能互补\\\\\\\"\\\\n\\\\n- title: \\\\\\\"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\\\\\\\"\\\\n  authors: [Jiho Shin, Hoeseok Yang, Youngmin Yi]\\\\n  venue: DATE 2025\\\\n  year: 2025\\\\n  arxiv_id: \\\\\\\"2411.12692\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"Training-free sign-bit predictor——极低开销的sparsity预测\\\\\\\"\\\\n  key_finding: \\\\\\\"仅比较input和weight的sign bits预测activation sparsity，无需训练。仅适用于ReLU-based LLMs，不适用SwiGLU\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"不适用于SwiGLU模型（我们的目标），但其sign-bit方法的简洁性值得参考。SwiGLU缺乏天然sparsity证明trained predictor的必要性\\\\\\\"\\\\n\\\\n- title: \\\\\\\"SVD Contextual Sparsity Predictors for Fast LLM Inference\\\\\\\"\\\\n  authors: [Georgii Serbin, Kirill Koshkin, Zhongao Sun, Anastasiya Bistrigova, C.C. Korikov]\\\\n  venue: arXiv\\\\n  year: 2026\\\\n  arxiv_id: \\\\\\\"2603.14110\\\\\\\"\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"Training-free SVD-based sparsity predictor——用gate projection矩阵的SVD做预测\\\\\\\"\\\\n  key_finding: \\\\\\\"对ReGLU FFN的gate projection矩阵做truncation-aware SVD构建sparse pattern predictor，90% FFN sparsity下1.8x decoding加速，benchmark降低<1%\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"虽然是training-free competitor，但focus在ReGLU（不是SwiGLU）且需要90%天然稀疏性。我们的方法在SwiGLU的50%目标sparsity下工作，使用场景不同\\\\\\\"\\\\n\\\\n- title: \\\\\\\"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\\\\\\\"\\\\n  authors: [Donghyun Lee, Je-Yong Lee, Genghan Zhang, Mo Tiwari, Azalia Mirhoseini]\\\\n  venue: arXiv\\\\n  year: 2024\\\\n  arxiv_id: \\\\\\\"2404.08763\\\\\\\"\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"Contextual thresholding——不训练predictor，用统计threshold做sparsity\\\\\\\"\\\\n  key_finding: \\\\\\\"为每个MLP层计算SiLU(x)激活的percentile threshold做sparsification，50% sparsity下性能降低1-2%，无需fine-tuning。Mistral-7B和Llama2-7B上验证\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"CATS直接在SwiGLU/SiLU模型上工作，是我们的直接competitor。但CATS是固定threshold不考虑input context，我们的trained predictor是input-dependent的，理论上更优\\\\\\\"\\\\n\\\\n- title: \\\\\\\"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\\\\\\\"\\\\n  authors: [Zhenyu Zhang, Zechun Liu, Yuandong Tian, Harshit Khaitan, Zhangyang Wang, Steven Li]\\\\n  venue: ICLR 2025\\\\n  year: 2025\\\\n  arxiv_id: \\\\\\\"2504.19449\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"Training-free rank-aware方法——利用input channel sparsity和SVD\\\\\\\"\\\\n  key_finding: \\\\\\\"用SVD分解将input channel sparsity映射到output，无需预测active channels。50% model-level sparsity下43%端到端加速\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"Training-free baseline。如果R-Sparse在SwiGLU模型上效果很好，我们需要证明trained KL predictor的额外训练成本是值得的\\\\\\\"\\\\n\\\\n- title: \\\\\\\"Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\\\\\\\"\\\\n  authors: [Marco Federici, Davide Belli, Mart van Baalen, Amir Jalalirad, Andrii Skliar, Bence Major, Markus Nagel, Paul Whatmough]\\\\n  venue: MLSys 2025\\\\n  year: 2024\\\\n  arxiv_id: \\\\\\\"2412.01380\\\\\\\"\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"Predictor-free dynamic pruning for SwiGLU——直接针对SwiGLU的magnitude pruning\\\\\\\"\\\\n  key_finding: \\\\\\\"Predictor-free方案动态剪枝SwiGLU MLP层，配合LoRA adapter恢复精度。Phi-3-Medium上46%内存减少+40%吞吐提升\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"直接针对SwiGLU的competitor。DIP证明SwiGLU的sparsity pattern难以预测（所以放弃predictor），我们的KL-trained predictor需要证明能克服这个挑战\\\\\\\"\\\\n\\\\n# =============================================================================\\\\n# 补充：Activation function替换和sparsity增强\\\\n# =============================================================================\\\\n\\\\n- title: \\\\\\\"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\\\\\\\"\\\\n  authors: [Iman Mirzadeh, Keivan Alizadeh, Sachin Mehta, Carlo C Del Mundo, Oncel Tuzel, Golnoosh Samei, Mohammad Rastegari, Mehrdad Farajtabar]\\\\n  venue: ICLR 2024\\\\n  year: 2024\\\\n  arxiv_id: \\\\\\\"2310.04564\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"ReLU替换SiLU获得天然sparsity——替代路线\\\\\\\"\\\\n  key_finding: \\\\\\\"用ReLU替换SiLU/GELU后continual pretraining，获得天然高稀疏性（>90%），推理计算减少3x\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"替代路线：修改activation function vs 训练predictor。我们的定位：不需要修改pretrained模型架构，作为plug-in predictor在现有SwiGLU模型上工作\\\\\\\"\\\\n\\\\n- title: \\\\\\\"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\\\\\\\"\\\\n  authors: [Yixin Song, Haotong Xie, Zhengyan Zhang, Bo Wen, Li Ma, Zeyu Mi, Haibo Chen]\\\\n  venue: arXiv\\\\n  year: 2024\\\\n  arxiv_id: \\\\\\\"2406.05955\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"dReLU获得90%+ sparsity——activation function工程的极致\\\\\\\"\\\\n  key_finding: \\\\\\\"提出dReLU使LLM达到近90% sparsity同时保持SOTA性能，2-5x decoding加速\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"与ReLU Strikes Back同一思路但更极端。我们不改activation function，这是差异化定位\\\\\\\"\\\\n\\\\n- title: \\\\\\\"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\\\\\\\"\\\\n  authors: [Chenyang Song, Xu Han, Zhengyan Zhang, Shengding Hu, Xiyu Shi, Kuai Li, Chen Chen, Zhiyuan Liu, Guangli Li, Tao Yang, Maosong Sun]\\\\n  venue: COLING 2025\\\\n  year: 2025\\\\n  arxiv_id: \\\\\\\"2402.13516\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"Progressive sparsification——渐进式增加sparsity regularization\\\\\\\"\\\\n  key_finding: \\\\\\\"三步法：ReLU替换→progressive sparsity regularization（沿sine curve增强）→threshold shifting(FATReLU)。LLaMA2-7B达89.32% sparsity\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"ProSparse的progressive training策略可参考：我们的KL predictor训练也可渐进式增加sparsity目标（已在Lagrangian约束中实现）\\\\\\\"\\\\n\\\\n- title: \\\\\\\"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\\\\\\\"\\\\n  authors: [Yuqi Luo, Chenyang Song, Xu Han, Yingfa Chen, Chaojun Xiao, Xiaojun Meng, Liqun Deng, Jiansheng Wei, Zhiyuan Liu, Maosong Sun]\\\\n  venue: arXiv\\\\n  year: 2024\\\\n  arxiv_id: \\\\\\\"2411.02335\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"Activation sparsity的scaling law——理论基础\\\\\\\"\\\\n  key_finding: \\\\\\\"SiLU/SwiGLU的activation ratio随训练递增（变密），ReLU递减（变稀）。Sparsity对parameter scale不敏感，与width-depth ratio线性相关\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"理论支撑：SiLU/SwiGLU模型天然不够稀疏（随训练变密），因此需要外部predictor/pruning来获得稀疏性——这是我们工作的motivation之一\\\\\\\"\\\\n\\\\n- title: \\\\\\\"A Sparsity Predicting Approach for Large Language Models via Activation Pattern Clustering\\\\\\\"\\\\n  authors: [Nobel Dhar, Bobin Deng, Md Romyull Islam, Xinyue Zhang, Kazi Fahim Ahmad Nasif, Kun Suo]\\\\n  venue: Euro-Par 2025\\\\n  year: 2025\\\\n  arxiv_id: \\\\\\\"2507.14179\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"Clustering-based sparsity prediction——用聚类简化prediction\\\\\\\"\\\\n  key_finding: \\\\\\\"将activation patterns聚类为representative clusters，预测cluster assignment而非individual neuron states，减少prediction开销。Mistral-7B上79.34%聚类精度\\\\\\\"\\\\n  relevance_to_us: \\\\\\\"降低predictor复杂度的思路。如果我们的per-neuron KL predictor开销太大，可考虑cluster-level prediction\\\\\\\"\\\\n\\\\n# =============================================================================\\\\n# 竞争格局总结\\\\n# =============================================================================\\\\n#\\\\n# 我们的独特定位:\\\\n# 1. 唯一使用KL divergence训练activation sparsity predictor的工作\\\\n#    - DejaVu/ShadowLLM用BCE训练predictor\\\\n#    - SPON用KL但训练bias correction而非predictor\\\\n#    - TEAL/CATS/R-Sparse/SparseInfer/SVD-CSP是training-free\\\\n# 2. 专注SwiGLU模型的50% sparsity目标\\\\n#    - ReLU/dReLU方案需要替换activation function\\\\n#    - 很多training-free方案在SwiGLU上效果不佳(DIP论文证实)\\\\n# 3. 通过保留output distribution(而非逐neuron匹配)来指导sparsity\\\\n#    - Minitron/SPON已证明KL loss优于MSE/BCE做distribution matching\\\\n#    - 我们将此insight应用到predictor训练\\\\n#\\\\n# 主要related work定位:\\\\n# - vs TEAL: trained predictor(input-dependent) vs fixed magnitude threshold\\\\n# - vs DejaVu/ShadowLLM: KL loss vs BCE loss训练predictor\\\\n# - vs SPON: predictor vs learnable bias; 都用KL但目标不同\\\\n# - vs DIP: trained predictor vs predictor-free pruning\\\\n# - vs ReLU/TurboSparse/ProSparse: 不改activation function\\\\n# - vs Fast Forward: KL loss vs BCE+error compensation\\\\n# - vs CATS: input-dependent predictor vs fixed percentile threshold\\\\n\\\", \\\"total_chars\\\": 13950, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/literature_map.yaml\", \"content\": \"# Literature Map: KL Distillation for Sparse SwiGLU Activation Prediction\\n# Last updated: 2026-05-15\\n# Survey scope: 2023-2026, 4 directions\\n\\n# =============================================================================\\n# Direction 1: KL distillation for structured/activation sparsity\\n# Finding: NO prior work uses KL to train an activation sparsity PREDICTOR.\\n# Existing predictors use BCE (DejaVu, ShadowLLM). SPON uses KL but for\\n# learnable bias correction, not predictor training. This is our novelty.\\n# =============================================================================\\n\\n- title: \\\"Resting Neurons, Active Insights: Robustify Activation Sparsity for Large Language Models\\\"\\n  authors: [Haotian Xu, Jiannan Yang, Tian Gao, Tsui-Wei Weng, Tengfei Ma]\\n  venue: ICML 2026\\n  year: 2026\\n  arxiv_id: \\\"2512.12744\\\"\\n  category: direct-competitor\\n  role: \\\"最接近的KL蒸馏用于稀疏性的工作——但SPON训练的是可学习bias项而非predictor\\\"\\n  key_finding: \\\"SPON注入input-independent learnable activation vectors作为sparse computation的anchor，用KL散度(dense vs sparse logits)做distribution matching训练，训练后吸收进bias项，零推理开销\\\"\\n  relevance_to_us: \\\"SPON证明KL divergence比BCE/MSE更适合sparsity场景的distribution matching。但SPON是全局bias correction而非per-token predictor——我们的predictor方案能实现input-dependent的sparsity pattern，比SPON更灵活。SPON在50-60% sparsity下测试，与我们目标一致\\\"\\n\\n- title: \\\"Compact Language Models via Pruning and Knowledge Distillation\\\"\\n  authors: [Saurav Muralidharan, Sharath Turuvekere Sreenivas, Raviraj Joshi, Marcin Chochowski, Mostofa Patwary, Mohammad Shoeybi, Bryan Catanzaro, Jan Kautz, Pavlo Molchanov]\\n  venue: NeurIPS 2024\\n  year: 2024\\n  arxiv_id: \\\"2407.14679\\\"\\n  category: method-component\\n  role: \\\"KL蒸馏用于结构化剪枝后恢复——验证logit-only KL优于intermediate matching\\\"\\n  key_finding: \\\"Minitron用logit-only forward KL divergence做structured pruning后的distillation recovery，发现仅用KL loss（不用CE或intermediate matching）效果最好，学生模型继承了teacher的inter-token关系和confidence calibration\\\"\\n  relevance_to_us: \\\"支持我们的核心假设：KL divergence保留output distribution比逐元素BCE更优。Minitron的发现（logit-only KL最优）为我们predictor的KL训练目标提供了理论支撑\\\"\\n\\n- title: \\\"Instruction-Following Pruning for Large Language Models\\\"\\n  authors: [Bairu Hou, Qibin Chen, Jianyu Wang, Guoli Yin, Chong Wang, Nan Du, Ruoming Pang, Shiyu Chang, Tao Lei]\\n  venue: ICML 2025\\n  year: 2025\\n  arxiv_id: \\\"2501.02086\\\"\\n  category: method-component\\n  role: \\\"训练sparse mask predictor的范式——input-dependent mask selection\\\"\\n  key_finding: \\\"训练一个sparse mask predictor以instruction为输入动态选择最相关参数子集，联合优化mask predictor和LLM\\\"\\n  relevance_to_us: \\\"架构上与我们类似（训练predictor生成mask），但目标是instruction-aware weight pruning而非activation sparsity。可参考其predictor-LLM联合优化策略\\\"\\n\\n# =============================================================================\\n# Direction 2: Output distribution preservation in pruning/sparsity\\n# =============================================================================\\n\\n- title: \\\"Distilling to Hybrid Attention Models via KL-Guided Layer Selection\\\"\\n  authors: []\\n  venue: arXiv\\n  year: 2025\\n  arxiv_id: \\\"2512.20569\\\"\\n  category: method-component\\n  role: \\\"KL散度引导layer selection——用distribution差异决定哪些层需要保留\\\"\\n  key_finding: \\\"用KL divergence作为指标选择哪些attention层替换为hybrid attention，通过最小化output distribution变化来指导架构决策\\\"\\n  relevance_to_us: \\\"方法论启示：KL divergence不仅可作为训练loss，还可作为layer-wise重要性指标。我们可用per-layer KL分析哪些层的sparsity对output distribution影响最大\\\"\\n\\n# =============================================================================\\n# Direction 3: SPON和类似的learnable bias correction for sparsity\\n# =============================================================================\\n\\n- title: \\\"Fast Forward: Accelerating LLM Prefill with Predictive FFN Sparsity\\\"\\n  authors: [Aayush Gautam, Mukul Gagrani, Junyoung Park, Mingu Lee, Chiris Lott, Narasimha Reddy]\\n  venue: arXiv\\n  year: 2026\\n  arxiv_id: \\\"2602.00397\\\"\\n  category: direct-competitor\\n  role: \\\"Predictor + error compensation双组件架构——与SPON的bias correction思路互补\\\"\\n  key_finding: \\\"组合三个组件：(1) lightweight expert predictor选择high-importance neurons，(2) error compensation network修正sparsity误差，(3) layer-wise sparsity scheduler分配计算。50% FFN sparsity下达到1.45x prefill加速\\\"\\n  relevance_to_us: \\\"与我们的方案最可比：都用predictor做activation sparsity。我们的差异在于用KL loss训练predictor而非BCE，且不需要额外的error compensation网络（KL loss本身应该能减少distribution shift）\\\"\\n\\n- title: \\\"Amber Pruner: Leveraging N:M Activation Sparsity for Efficient Prefill in Large Language Models\\\"\\n  authors: [Tai An, Ruwu Cai, Yanzhe Zhang, Yang Liu, Hao Chen, Pengcheng Xie, Sheng Chang, Yiwu Yao, Gongyi Wang]\\n  venue: arXiv\\n  year: 2025\\n  arxiv_id: \\\"2508.02128\\\"\\n  category: background\\n  role: \\\"N:M structured activation sparsity——hardware-friendly的sparsity pattern\\\"\\n  key_finding: \\\"Training-free的top-k策略在linear projection层内确定N:M activation masks，在2:4/4:8/8:16多种ratio下有效，可与W8A8量化组合\\\"\\n  relevance_to_us: \\\"如果我们的predictor输出改为N:M structured pattern而非unstructured binary mask，可获得更好的hardware加速。值得作为future work\\\"\\n\\n# =============================================================================\\n# Direction 4: Predictor-based activation sparsity (TEAL, DejaVu, PowerInfer等)\\n# =============================================================================\\n\\n- title: \\\"Training-Free Activation Sparsity in Large Language Models\\\"\\n  authors: [James Liu, Pragaash Ponnusamy, Tianle Cai, Han Guo, Yoon Kim, Ben Athiwaratkun]\\n  venue: ICLR 2025 (Spotlight)\\n  year: 2025\\n  arxiv_id: \\\"2408.14690\\\"\\n  category: direct-competitor\\n  role: \\\"TEAL——我们的主要baseline，training-free magnitude pruning\\\"\\n  key_finding: \\\"对所有hidden states施加magnitude-based sparsity（不需训练），在40-50% sparsity下性能降低很小，Llama-2/3和Mistral 7B-70B上验证。50% sparsity下1.8x decoding加速\\\"\\n  relevance_to_us: \\\"TEAL用BCE度量sparsity mask质量（二元对错），我们的核心论点是：BCE只看neuron是否激活的对错，忽略了错误预测对output distribution的差异化影响。KL loss应该能让predictor学到'哪些neuron的错误预测对output影响更大'\\\"\\n\\n- title: \\\"Deja Vu: Contextual Sparsity for Efficient LLMs at Inference Time\\\"\\n  authors: [Zichang Liu, Jue Wang, Tri Dao, Tianyi Zhou, Binhang Yuan, Zhao Song, Anshumali Shrivastava, Ce Zhang, Yuandong Tian, Christopher Re, Beidi Chen]\\n  venue: ICML 2023\\n  year: 2023\\n  arxiv_id: \\\"2310.17157\\\"\\n  category: direct-competitor\\n  role: \\\"Predictor-based contextual sparsity的开创性工作——我们的直接对比对象\\\"\\n  key_finding: \\\"用两层MLP predictor预测每层的contextual sparsity pattern（哪些attention heads和MLP neurons可跳过），在OPT-175B上实现2x加速。Predictor用BCE训练\\\"\\n  relevance_to_us: \\\"DejaVu是predictor-based sparsity的baseline。其predictor用BCE训练——我们改用KL loss训练类似的predictor。关键差异：DejaVu在per-neuron level用BCE，我们在output distribution level用KL\\\"\\n\\n- title: \\\"ShadowLLM: Predictor-based Contextual Sparsity for Large Language Models\\\"\\n  authors: [Yash Akhauri, Ahmed F AbouElhamayed, Jordan Dotzel, Zhiru Zhang, Alexander M Rush, Safeen Huda, Mohamed S Abdelfattah]\\n  venue: EMNLP 2024\\n  year: 2024\\n  arxiv_id: \\\"2406.16635\\\"\\n  category: direct-competitor\\n  role: \\\"DejaVu的改进——更好的predictor架构和sparsity pattern enforcement\\\"\\n  key_finding: \\\"Shadow predictor超越magnitude-based pruning，context-dependent评估attention head和neuron重要性。比DejaVu端到端精度提升15%，速度提升20%\\\"\\n  relevance_to_us: \\\"ShadowLLM改进了predictor架构但仍用BCE-style loss。我们的改进方向正交：不改predictor架构，改训练loss（BCE→KL）。两种改进可能互补\\\"\\n\\n- title: \\\"SparseInfer: Training-free Prediction of Activation Sparsity for Fast LLM Inference\\\"\\n  authors: [Jiho Shin, Hoeseok Yang, Youngmin Yi]\\n  venue: DATE 2025\\n  year: 2025\\n  arxiv_id: \\\"2411.12692\\\"\\n  category: background\\n  role: \\\"Training-free sign-bit predictor——极低开销的sparsity预测\\\"\\n  key_finding: \\\"仅比较input和weight的sign bits预测activation sparsity，无需训练。仅适用于ReLU-based LLMs，不适用SwiGLU\\\"\\n  relevance_to_us: \\\"不适用于SwiGLU模型（我们的目标），但其sign-bit方法的简洁性值得参考。SwiGLU缺乏天然sparsity证明trained predictor的必要性\\\"\\n\\n- title: \\\"SVD Contextual Sparsity Predictors for Fast LLM Inference\\\"\\n  authors: [Georgii Serbin, Kirill Koshkin, Zhongao Sun, Anastasiya Bistrigova, C.C. Korikov]\\n  venue: arXiv\\n  year: 2026\\n  arxiv_id: \\\"2603.14110\\\"\\n  category: direct-competitor\\n  role: \\\"Training-free SVD-based sparsity predictor——用gate projection矩阵的SVD做预测\\\"\\n  key_finding: \\\"对ReGLU FFN的gate projection矩阵做truncation-aware SVD构建sparse pattern predictor，90% FFN sparsity下1.8x decoding加速，benchmark降低<1%\\\"\\n  relevance_to_us: \\\"虽然是training-free competitor，但focus在ReGLU（不是SwiGLU）且需要90%天然稀疏性。我们的方法在SwiGLU的50%目标sparsity下工作，使用场景不同\\\"\\n\\n- title: \\\"CATS: Contextually-Aware Thresholding for Sparsity in Large Language Models\\\"\\n  authors: [Donghyun Lee, Je-Yong Lee, Genghan Zhang, Mo Tiwari, Azalia Mirhoseini]\\n  venue: arXiv\\n  year: 2024\\n  arxiv_id: \\\"2404.08763\\\"\\n  category: direct-competitor\\n  role: \\\"Contextual thresholding——不训练predictor，用统计threshold做sparsity\\\"\\n  key_finding: \\\"为每个MLP层计算SiLU(x)激活的percentile threshold做sparsification，50% sparsity下性能降低1-2%，无需fine-tuning。Mistral-7B和Llama2-7B上验证\\\"\\n  relevance_to_us: \\\"CATS直接在SwiGLU/SiLU模型上工作，是我们的直接competitor。但CATS是固定threshold不考虑input context，我们的trained predictor是input-dependent的，理论上更优\\\"\\n\\n- title: \\\"R-Sparse: Rank-Aware Activation Sparsity for Efficient LLM Inference\\\"\\n  authors: [Zhenyu Zhang, Zechun Liu, Yuandong Tian, Harshit Khaitan, Zhangyang Wang, Steven Li]\\n  venue: ICLR 2025\\n  year: 2025\\n  arxiv_id: \\\"2504.19449\\\"\\n  category: background\\n  role: \\\"Training-free rank-aware方法——利用input channel sparsity和SVD\\\"\\n  key_finding: \\\"用SVD分解将input channel sparsity映射到output，无需预测active channels。50% model-level sparsity下43%端到端加速\\\"\\n  relevance_to_us: \\\"Training-free baseline。如果R-Sparse在SwiGLU模型上效果很好，我们需要证明trained KL predictor的额外训练成本是值得的\\\"\\n\\n- title: \\\"Efficient LLM Inference using Dynamic Input Pruning and Cache-Aware Masking\\\"\\n  authors: [Marco Federici, Davide Belli, Mart van Baalen, Amir Jalalirad, Andrii Skliar, Bence Major, Markus Nagel, Paul Whatmough]\\n  venue: MLSys 2025\\n  year: 2024\\n  arxiv_id: \\\"2412.01380\\\"\\n  category: direct-competitor\\n  role: \\\"Predictor-free dynamic pruning for SwiGLU——直接针对SwiGLU的magnitude pruning\\\"\\n  key_finding: \\\"Predictor-free方案动态剪枝SwiGLU MLP层，配合LoRA adapter恢复精度。Phi-3-Medium上46%内存减少+40%吞吐提升\\\"\\n  relevance_to_us: \\\"直接针对SwiGLU的competitor。DIP证明SwiGLU的sparsity pattern难以预测（所以放弃predictor），我们的KL-trained predictor需要证明能克服这个挑战\\\"\\n\\n# =============================================================================\\n# 补充：Activation function替换和sparsity增强\\n# =============================================================================\\n\\n- title: \\\"ReLU Strikes Back: Exploiting Activation Sparsity in Large Language Models\\\"\\n  authors: [Iman Mirzadeh, Keivan Alizadeh, Sachin Mehta, Carlo C Del Mundo, Oncel Tuzel, Golnoosh Samei, Mohammad Rastegari, Mehrdad Farajtabar]\\n  venue: ICLR 2024\\n  year: 2024\\n  arxiv_id: \\\"2310.04564\\\"\\n  category: background\\n  role: \\\"ReLU替换SiLU获得天然sparsity——替代路线\\\"\\n  key_finding: \\\"用ReLU替换SiLU/GELU后continual pretraining，获得天然高稀疏性（>90%），推理计算减少3x\\\"\\n  relevance_to_us: \\\"替代路线：修改activation function vs 训练predictor。我们的定位：不需要修改pretrained模型架构，作为plug-in predictor在现有SwiGLU模型上工作\\\"\\n\\n- title: \\\"Turbo Sparse: Achieving LLM SOTA Performance with Minimal Activated Parameters\\\"\\n  authors: [Yixin Song, Haotong Xie, Zhengyan Zhang, Bo Wen, Li Ma, Zeyu Mi, Haibo Chen]\\n  venue: arXiv\\n  year: 2024\\n  arxiv_id: \\\"2406.05955\\\"\\n  category: background\\n  role: \\\"dReLU获得90%+ sparsity——activation function工程的极致\\\"\\n  key_finding: \\\"提出dReLU使LLM达到近90% sparsity同时保持SOTA性能，2-5x decoding加速\\\"\\n  relevance_to_us: \\\"与ReLU Strikes Back同一思路但更极端。我们不改activation function，这是差异化定位\\\"\\n\\n- title: \\\"ProSparse: Introducing and Enhancing Intrinsic Activation Sparsity within Large Language Models\\\"\\n  authors: [Chenyang Song, Xu Han, Zhengyan Zhang, Shengding Hu, Xiyu Shi, Kuai Li, Chen Chen, Zhiyuan Liu, Guangli Li, Tao Yang, Maosong Sun]\\n  venue: COLING 2025\\n  year: 2025\\n  arxiv_id: \\\"2402.13516\\\"\\n  category: background\\n  role: \\\"Progressive sparsification——渐进式增加sparsity regularization\\\"\\n  key_finding: \\\"三步法：ReLU替换→progressive sparsity regularization（沿sine curve增强）→threshold shifting(FATReLU)。LLaMA2-7B达89.32% sparsity\\\"\\n  relevance_to_us: \\\"ProSparse的progressive training策略可参考：我们的KL predictor训练也可渐进式增加sparsity目标（已在Lagrangian约束中实现）\\\"\\n\\n- title: \\\"Sparsing Law: Towards Large Language Models with Greater Activation Sparsity\\\"\\n  authors: [Yuqi Luo, Chenyang Song, Xu Han, Yingfa Chen, Chaojun Xiao, Xiaojun Meng, Liqun Deng, Jiansheng Wei, Zhiyuan Liu, Maosong Sun]\\n  venue: arXiv\\n  year: 2024\\n  arxiv_id: \\\"2411.02335\\\"\\n  category: background\\n  role: \\\"Activation sparsity的scaling law——理论基础\\\"\\n  key_finding: \\\"SiLU/SwiGLU的activation ratio随训练递增（变密），ReLU递减（变稀）。Sparsity对parameter scale不敏感，与width-depth ratio线性相关\\\"\\n  relevance_to_us: \\\"理论支撑：SiLU/SwiGLU模型天然不够稀疏（随训练变密），因此需要外部predictor/pruning来获得稀疏性——这是我们工作的motivation之一\\\"\\n\\n- title: \\\"A Sparsity Predicting Approach for Large Language Models via Activation Pattern Clustering\\\"\\n  authors: [Nobel Dhar, Bobin Deng, Md Romyull Islam, Xinyue Zhang, Kazi Fahim Ahmad Nasif, Kun Suo]\\n  venue: Euro-Par 2025\\n  year: 2025\\n  arxiv_id: \\\"2507.14179\\\"\\n  category: background\\n  role: \\\"Clustering-based sparsity prediction——用聚类简化prediction\\\"\\n  key_finding: \\\"将activation patterns聚类为representative clusters，预测cluster assignment而非individual neuron states，减少prediction开销。Mistral-7B上79.34%聚类精度\\\"\\n  relevance_to_us: \\\"降低predictor复杂度的思路。如果我们的per-neuron KL predictor开销太大，可考虑cluster-level prediction\\\"\\n\\n# =============================================================================\\n# 竞争格局总结\\n# =============================================================================\\n#\\n# 我们的独特定位:\\n# 1. 唯一使用KL divergence训练activation sparsity predictor的工作\\n#    - DejaVu/ShadowLLM用BCE训练predictor\\n#    - SPON用KL但训练bias correction而非predictor\\n#    - TEAL/CATS/R-Sparse/SparseInfer/SVD-CSP是training-free\\n# 2. 专注SwiGLU模型的50% sparsity目标\\n#    - ReLU/dReLU方案需要替换activation function\\n#    - 很多training-free方案在SwiGLU上效果不佳(DIP论文证实)\\n# 3. 通过保留output distribution(而非逐neuron匹配)来指导sparsity\\n#    - Minitron/SPON已证明KL loss优于MSE/BCE做distribution matching\\n#    - 我们将此insight应用到predictor训练\\n#\\n# 主要related work定位:\\n# - vs TEAL: trained predictor(input-dependent) vs fixed magnitude threshold\\n# - vs DejaVu/ShadowLLM: KL loss vs BCE loss训练predictor\\n# - vs SPON: predictor vs learnable bias; 都用KL但目标不同\\n# - vs DIP: trained predictor vs predictor-free pruning\\n# - vs ReLU/TurboSparse/ProSparse: 不改activation function\\n# - vs Fast Forward: KL loss vs BCE+error compensation\\n# - vs CATS: input-dependent predictor vs fixed percentile threshold\\n\", \"total_chars\": 13950, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 9_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01Fq7V6j9XtFKBxeGQxk9nWL`</summary>

```json
{
  "project": "distill_sparse_swiglu",
  "file": "memory.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "de2d7dca-78b6-4c45-b6c4-ec1d0c4250ff",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FEX6H8w4CEpKbpFF3nowdh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 454,
      "cache_read_input_tokens": 24303,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 454
      },
      "output_tokens": 66,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-16T02:26:49.492Z_

<details><summary>↩ Tool result · `toolu_01Fq7V6j9XtFKBxeGQxk9nWL`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/memory.md\", \"content\": \"# Project Memory\\n\\n## Paper Framing Decisions (Director-approved)\\n\\n### BCE vs training-free: \\\"objective mismatch\\\" 非 \\\"anti-learning\\\" (2026-05-16)\\nBCE (54.84) 比 training-free (23-33) 差。**禁止用 \\\"anti-learning\\\" framing**，改用 **\\\"objective mismatch\\\"**：BCE 优化 per-neuron binary accuracy，TEAL 推理用 global top-k 重分配，两者结构性不兼容。BCE 学到的 per-neuron scoring 在 global budget allocation 下不是最优的。正确 claim: loss function 必须匹配推理管线的 sparsity allocation 机制。KL 直接优化 output distribution，天然兼容任何 allocation 策略。\\n\\n### KL PPL 统一引用规范 (2026-05-16)\\n论文中所有 KL PPL 对比统一用 **4-seed mean 12.00±0.07**（TEAL sparse PPL），不要用单 seed 最佳值 11.91。BCE iso-compute 对比时标注步数（1000 步 vs KL 1000 步，但 BCE per-step FLOPs 仅 KL 的 1/2.71）。\\n\\n### SPON framing: \\\"marginal complement\\\" 非 \\\"subsumption\\\" (2026-05-15)\\n禁止 \\\"KL subsumes SPON\\\" 措辞。正确表述：SPON corrections are orthogonal to and much smaller than predictor mask effects (cos_sim=0.196, magnitude ratio=16%)。D010 \\\"marginal complement\\\" framing。\\n\\n### s456 outlier 报告方式 (2026-05-16)\\n报 \\\"5-seed mean: 12.32±0.71\\\" + \\\"Excluding s456 (TEAL allocation outlier): 12.00±0.07\\\"。附 per-seed breakdown table + Layer 31 keep ratio 分析。不跑第 6 个 seed。\\n\\n## Key Insights (non-metrics)\\n\\n### 50% sparsity 摧毁 autoregressive generation (2026-05-16)\\nGSM8K 生成对比（10 samples）：sparse 50% 模型 1-3 句后进入无限重复循环，0/10 正确。退化模式是推理能力根本性丧失（模式 A），非仅数字算错。PPL 不惩罚 repetition loop（每个重复 token 仍有较高概率）。这解释了 PPL 12.00 但 GSM8K exact_match 仅 0.0121 的 disconnect。论文需用 30% 数据展示 sparsity-task tradeoff。\\n\\n### PPL-downstream disconnect 是真实现象，非 eval bug (2026-05-16)\\n三重验证确认：(1) acc_norm 已正确使用，(2) mask 逻辑审查无 bug（HFLM logit diff=0.0），(3) 生成对比显示推理链断裂。根因：50% sparsity 下 logit 微小偏移（如 \\\"Paris\\\" 从 #2 降到 #5）足以翻转 4-choice 答案，且摧毁 autoregressive 推理链。\\n\\n### PPL-downstream disconnect 文献支撑 (2026-05-16)\\n文献调研确认这是**已知但未充分研究**的现象。核心证据：(1) Khanal & Capone (2024): SparseGPT/Wanda 在 50% sparsity 保持 PPL 但下游退化，\\\"perplexity as sole evaluation metric is inadequate\\\"; (2) Xu et al. (2024, EMNLP): PPL 在 45-60% sparsity 前无变化但完全无法捕捉能力退化; (3) Kodathala & Vunnam (2026): N:M pruning 25-30% sparsity 下 factual QA 崩溃 97% 但 PPL 不变; (4) Siam et al. (2026): 定义 Type 2 trap（推理断裂后重复循环），与我们的 GSM8K 退化模式完全一致。**文献空白：无论文在 contextual sparsity predictor + KL distillation 下系统研究此现象。** 详细报告见 artifacts/literature_ppl_downstream_disconnect.md。\\n\\n### STE vs Gumbel: smooth gradient is essential for KL+Lagrangian training (2026-05-16)\\nSTE hard threshold causes violent lambda oscillation (range [0.01, 1000], overall std=354) because sigmoid→binary 翻转是离散的——微小参数变化可翻转大量 neuron，导致 constraint violation 剧烈跳变。后果：(1) per-token sparsity 仅 0.470（未达 target 0.50）, (2) 逐层稀疏度两极化（Layer 0-17: 5-56%, Layer 18-31: 56-90%）, (3) TEAL global 分配效果差（PPL 15.77 vs Gumbel 12.00）。Gumbel soft mask 提供连续梯度，lambda 平稳收敛到 cap，sparsity 精准收敛到 target。**Relaxation method 不是实现细节，是 KL distillation 训练稳定性的前提。**\\n\\n### KL predictor implicitly subsumes static correction (2026-05-15)\\nSPON bias vectors recover only 3.8% of sparse-vs-dense gap on top of KL predictor (PPL 9.22→9.10). Root cause: KL's end-to-end gradient already captures average-case AND per-input neuron importance through d_logits/dh * dh/dm coupling. Static bias correction is redundant when the contextual predictor is trained with output-distribution alignment.\\n\\n### SPON seq_len=2048 confirms subsumption, rules out mismatch confound (2026-05-15)\\nspon_2048_s42: training seq_len matched eval seq_len=2048. Recovery improved 3.8%→7.3% (+3.5pp), bias norm 0.041→0.053 (+30%), but still < 10% threshold. Even under matched conditions, static bias is fundamentally limited against KL predictor's per-token mask.\\n\\n### Compensation cannot fix BCE's fundamental flaw (2026-05-15)\\nBCE+Compensation (67.2M params, staged training) only improves per-token PPL by 9% (27.96→25.44), still 2.8x worse than KL-only (9.21). TEAL global path completely unaffected by comp network (44.54 = BCE-only). Root cause: BCE gradient dL/ds_j is per-neuron factorized.\\n\\n### Training-free baselines: per-layer normalization is critical (2026-05-16)\\nCRITICAL bug in _global_topk_masks: activation magnitudes vary 50-100x across layers. Fix: divide each layer's importance scores by layer mean before global topk. Corrected PPL: Vanilla TEAL 23.31, WINA 27.93, TEAL Greedy 33.47. R-Sparse still broken (SVD scores need percentile/max normalization). **Same bug likely affects predictor TEAL path** — sparsity70 TEAL PPL=136K anomaly.\\n\\n### BCE objective mismatch with TEAL inference (2026-05-16)\\nBCE iso-compute (1000 steps, reg_weight=2.0, sparsity=0.502) gets TEAL PPL=54.84 — worse than all 3 training-free baselines (23-33). Root cause: BCE optimizes per-neuron binary accuracy independently, but TEAL inference uses global top-k budget allocation across layers. Per-neuron scores optimized for binary accuracy are structurally incompatible with global budget allocation. KL directly optimizes output distribution, naturally compatible with any allocation strategy.\\n\\n### Hard-mask PPL vs TEAL sparse PPL variance separation (2026-05-15)\\n5-seed hard-mask PPL std = 0.04 (9.14-9.25), 极其稳定。TEAL sparse PPL std = 0.69 (11.91-13.58), 方差大 16 倍。方差来自 TEAL 全局分配算法与 per-token mask 的匹配度。\\n\\n### KL vs BCE per-step FLOPs ratio = 2.71x (2026-05-15)\\n实测 (BS=1, SL=512): KL 0.549s/step, BCE 0.202s/step。Iso-compute BCE 需要 2700 步 (= 1000 × 2.71) 匹配 KL 1000 步的总 FLOPs。\\n\\n### gradient_checkpointing 对 sparsity training 是必须的 (2026-05-15)\\n所有 LLaMA-3.1-8B sparsity 训练必须加 --gradient_checkpointing。不加则 OOM（>96GB），加了后 46.9-67.6GB。\\n\\n### BCE iso-compute sparsity 收敛需要 reg_weight=2.0 (2026-05-15)\\n原始 SparsityRegularizer 在 torch.no_grad() 下计算 mask，梯度为零。修复：STE hard mask + reg_weight=2.0。\\n\\n### lambda_max=1000 对低 sparsity target 不够 (2026-05-16)\\nsparsity30 (target=0.30) 两次 sparsity 卡在 0.281，lambda 撞 1000 cap。v3 用 lambda_max=5000。\\n\\n### Mistral-7B 与 Llama-3.1-8B 代码完全兼容 (2026-05-16)\\ntrain.py 零改动即可运行。架构一致。Predictor 参数量完全相同 (~75.96M)。vocab_size 差异只影响 KL loss logit 维度。\\n\\n## Checkpoints\\n- KL-only predictor (s42): `/root/distill_sparse_swiglu/checkpoints/mvp_kl_norm_v2_s42/predictor_kl_normalized.pt`\\n- SPON biases (seq128): `/root/distill_sparse_swiglu/checkpoints/spon_kl_s42/spon_biases.pt` (928KB)\\n- SPON biases (seq2048): `/root/distill_sparse_swiglu/checkpoints/spon_2048_s42/`\\n- BCE+comp predictor: `/root/distill_sparse_swiglu/checkpoints/bce_comp_staged_s42/predictor_bce_comp.pt`\\n- BCE iso-compute v2 (s42): `/root/distill_sparse_swiglu/checkpoints/bce_isocompute_v2_s42/`\\n- SPON eval script: `/root/distill_sparse_swiglu/src/eval_spon.py`\\n- Mistral-7B: `/root/autodl-tmp/models/mistral-7b/` (7.25B params, 14MB)\\n- KL sparsity70 (s42): `/root/distill_sparse_swiglu/checkpoints/kl_sparsity70_s42/predictor_kl_normalized.pt`\\n- KL sparsity30 v2 (s42): `/root/distill_sparse_swiglu/checkpoints/kl_sparsity30_s42/predictor_kl_normalized.pt` (sparsity=0.281, negative)\\n- KL sparsity30 v3 (s42): `/root/distill_sparse_swiglu/checkpoints/kl_sparsity30_s42_v3/predictor_kl_normalized.pt` (145MB)\\n- STE baseline (s42): `/root/distill_sparse_swiglu/checkpoints/ste_baseline_s42/`\\n\", \"total_chars\": 6933, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "7d5a3620-0002-49ad-8d00-fab5f15eb7ee",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/memory.md\\\", \\\"content\\\": \\\"# Project Memory\\\\n\\\\n## Paper Framing Decisions (Director-approved)\\\\n\\\\n### BCE vs training-free: \\\\\\\"objective mismatch\\\\\\\" 非 \\\\\\\"anti-learning\\\\\\\" (2026-05-16)\\\\nBCE (54.84) 比 training-free (23-33) 差。**禁止用 \\\\\\\"anti-learning\\\\\\\" framing**，改用 **\\\\\\\"objective mismatch\\\\\\\"**：BCE 优化 per-neuron binary accuracy，TEAL 推理用 global top-k 重分配，两者结构性不兼容。BCE 学到的 per-neuron scoring 在 global budget allocation 下不是最优的。正确 claim: loss function 必须匹配推理管线的 sparsity allocation 机制。KL 直接优化 output distribution，天然兼容任何 allocation 策略。\\\\n\\\\n### KL PPL 统一引用规范 (2026-05-16)\\\\n论文中所有 KL PPL 对比统一用 **4-seed mean 12.00±0.07**（TEAL sparse PPL），不要用单 seed 最佳值 11.91。BCE iso-compute 对比时标注步数（1000 步 vs KL 1000 步，但 BCE per-step FLOPs 仅 KL 的 1/2.71）。\\\\n\\\\n### SPON framing: \\\\\\\"marginal complement\\\\\\\" 非 \\\\\\\"subsumption\\\\\\\" (2026-05-15)\\\\n禁止 \\\\\\\"KL subsumes SPON\\\\\\\" 措辞。正确表述：SPON corrections are orthogonal to and much smaller than predictor mask effects (cos_sim=0.196, magnitude ratio=16%)。D010 \\\\\\\"marginal complement\\\\\\\" framing。\\\\n\\\\n### s456 outlier 报告方式 (2026-05-16)\\\\n报 \\\\\\\"5-seed mean: 12.32±0.71\\\\\\\" + \\\\\\\"Excluding s456 (TEAL allocation outlier): 12.00±0.07\\\\\\\"。附 per-seed breakdown table + Layer 31 keep ratio 分析。不跑第 6 个 seed。\\\\n\\\\n## Key Insights (non-metrics)\\\\n\\\\n### 50% sparsity 摧毁 autoregressive generation (2026-05-16)\\\\nGSM8K 生成对比（10 samples）：sparse 50% 模型 1-3 句后进入无限重复循环，0/10 正确。退化模式是推理能力根本性丧失（模式 A），非仅数字算错。PPL 不惩罚 repetition loop（每个重复 token 仍有较高概率）。这解释了 PPL 12.00 但 GSM8K exact_match 仅 0.0121 的 disconnect。论文需用 30% 数据展示 sparsity-task tradeoff。\\\\n\\\\n### PPL-downstream disconnect 是真实现象，非 eval bug (2026-05-16)\\\\n三重验证确认：(1) acc_norm 已正确使用，(2) mask 逻辑审查无 bug（HFLM logit diff=0.0），(3) 生成对比显示推理链断裂。根因：50% sparsity 下 logit 微小偏移（如 \\\\\\\"Paris\\\\\\\" 从 #2 降到 #5）足以翻转 4-choice 答案，且摧毁 autoregressive 推理链。\\\\n\\\\n### PPL-downstream disconnect 文献支撑 (2026-05-16)\\\\n文献调研确认这是**已知但未充分研究**的现象。核心证据：(1) Khanal & Capone (2024): SparseGPT/Wanda 在 50% sparsity 保持 PPL 但下游退化，\\\\\\\"perplexity as sole evaluation metric is inadequate\\\\\\\"; (2) Xu et al. (2024, EMNLP): PPL 在 45-60% sparsity 前无变化但完全无法捕捉能力退化; (3) Kodathala & Vunnam (2026): N:M pruning 25-30% sparsity 下 factual QA 崩溃 97% 但 PPL 不变; (4) Siam et al. (2026): 定义 Type 2 trap（推理断裂后重复循环），与我们的 GSM8K 退化模式完全一致。**文献空白：无论文在 contextual sparsity predictor + KL distillation 下系统研究此现象。** 详细报告见 artifacts/literature_ppl_downstream_disconnect.md。\\\\n\\\\n### STE vs Gumbel: smooth gradient is essential for KL+Lagrangian training (2026-05-16)\\\\nSTE hard threshold causes violent lambda oscillation (range [0.01, 1000], overall std=354) because sigmoid→binary 翻转是离散的——微小参数变化可翻转大量 neuron，导致 constraint violation 剧烈跳变。后果：(1) per-token sparsity 仅 0.470（未达 target 0.50）, (2) 逐层稀疏度两极化（Layer 0-17: 5-56%, Layer 18-31: 56-90%）, (3) TEAL global 分配效果差（PPL 15.77 vs Gumbel 12.00）。Gumbel soft mask 提供连续梯度，lambda 平稳收敛到 cap，sparsity 精准收敛到 target。**Relaxation method 不是实现细节，是 KL distillation 训练稳定性的前提。**\\\\n\\\\n### KL predictor implicitly subsumes static correction (2026-05-15)\\\\nSPON bias vectors recover only 3.8% of sparse-vs-dense gap on top of KL predictor (PPL 9.22→9.10). Root cause: KL's end-to-end gradient already captures average-case AND per-input neuron importance through d_logits/dh * dh/dm coupling. Static bias correction is redundant when the contextual predictor is trained with output-distribution alignment.\\\\n\\\\n### SPON seq_len=2048 confirms subsumption, rules out mismatch confound (2026-05-15)\\\\nspon_2048_s42: training seq_len matched eval seq_len=2048. Recovery improved 3.8%→7.3% (+3.5pp), bias norm 0.041→0.053 (+30%), but still < 10% threshold. Even under matched conditions, static bias is fundamentally limited against KL predictor's per-token mask.\\\\n\\\\n### Compensation cannot fix BCE's fundamental flaw (2026-05-15)\\\\nBCE+Compensation (67.2M params, staged training) only improves per-token PPL by 9% (27.96→25.44), still 2.8x worse than KL-only (9.21). TEAL global path completely unaffected by comp network (44.54 = BCE-only). Root cause: BCE gradient dL/ds_j is per-neuron factorized.\\\\n\\\\n### Training-free baselines: per-layer normalization is critical (2026-05-16)\\\\nCRITICAL bug in _global_topk_masks: activation magnitudes vary 50-100x across layers. Fix: divide each layer's importance scores by layer mean before global topk. Corrected PPL: Vanilla TEAL 23.31, WINA 27.93, TEAL Greedy 33.47. R-Sparse still broken (SVD scores need percentile/max normalization). **Same bug likely affects predictor TEAL path** — sparsity70 TEAL PPL=136K anomaly.\\\\n\\\\n### BCE objective mismatch with TEAL inference (2026-05-16)\\\\nBCE iso-compute (1000 steps, reg_weight=2.0, sparsity=0.502) gets TEAL PPL=54.84 — worse than all 3 training-free baselines (23-33). Root cause: BCE optimizes per-neuron binary accuracy independently, but TEAL inference uses global top-k budget allocation across layers. Per-neuron scores optimized for binary accuracy are structurally incompatible with global budget allocation. KL directly optimizes output distribution, naturally compatible with any allocation strategy.\\\\n\\\\n### Hard-mask PPL vs TEAL sparse PPL variance separation (2026-05-15)\\\\n5-seed hard-mask PPL std = 0.04 (9.14-9.25), 极其稳定。TEAL sparse PPL std = 0.69 (11.91-13.58), 方差大 16 倍。方差来自 TEAL 全局分配算法与 per-token mask 的匹配度。\\\\n\\\\n### KL vs BCE per-step FLOPs ratio = 2.71x (2026-05-15)\\\\n实测 (BS=1, SL=512): KL 0.549s/step, BCE 0.202s/step。Iso-compute BCE 需要 2700 步 (= 1000 × 2.71) 匹配 KL 1000 步的总 FLOPs。\\\\n\\\\n### gradient_checkpointing 对 sparsity training 是必须的 (2026-05-15)\\\\n所有 LLaMA-3.1-8B sparsity 训练必须加 --gradient_checkpointing。不加则 OOM（>96GB），加了后 46.9-67.6GB。\\\\n\\\\n### BCE iso-compute sparsity 收敛需要 reg_weight=2.0 (2026-05-15)\\\\n原始 SparsityRegularizer 在 torch.no_grad() 下计算 mask，梯度为零。修复：STE hard mask + reg_weight=2.0。\\\\n\\\\n### lambda_max=1000 对低 sparsity target 不够 (2026-05-16)\\\\nsparsity30 (target=0.30) 两次 sparsity 卡在 0.281，lambda 撞 1000 cap。v3 用 lambda_max=5000。\\\\n\\\\n### Mistral-7B 与 Llama-3.1-8B 代码完全兼容 (2026-05-16)\\\\ntrain.py 零改动即可运行。架构一致。Predictor 参数量完全相同 (~75.96M)。vocab_size 差异只影响 KL loss logit 维度。\\\\n\\\\n## Checkpoints\\\\n- KL-only predictor (s42): `/root/distill_sparse_swiglu/checkpoints/mvp_kl_norm_v2_s42/predictor_kl_normalized.pt`\\\\n- SPON biases (seq128): `/root/distill_sparse_swiglu/checkpoints/spon_kl_s42/spon_biases.pt` (928KB)\\\\n- SPON biases (seq2048): `/root/distill_sparse_swiglu/checkpoints/spon_2048_s42/`\\\\n- BCE+comp predictor: `/root/distill_sparse_swiglu/checkpoints/bce_comp_staged_s42/predictor_bce_comp.pt`\\\\n- BCE iso-compute v2 (s42): `/root/distill_sparse_swiglu/checkpoints/bce_isocompute_v2_s42/`\\\\n- SPON eval script: `/root/distill_sparse_swiglu/src/eval_spon.py`\\\\n- Mistral-7B: `/root/autodl-tmp/models/mistral-7b/` (7.25B params, 14MB)\\\\n- KL sparsity70 (s42): `/root/distill_sparse_swiglu/checkpoints/kl_sparsity70_s42/predictor_kl_normalized.pt`\\\\n- KL sparsity30 v2 (s42): `/root/distill_sparse_swiglu/checkpoints/kl_sparsity30_s42/predictor_kl_normalized.pt` (sparsity=0.281, negative)\\\\n- KL sparsity30 v3 (s42): `/root/distill_sparse_swiglu/checkpoints/kl_sparsity30_s42_v3/predictor_kl_normalized.pt` (145MB)\\\\n- STE baseline (s42): `/root/distill_sparse_swiglu/checkpoints/ste_baseline_s42/`\\\\n\\\", \\\"total_chars\\\": 6933, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/memory.md\", \"content\": \"# Project Memory\\n\\n## Paper Framing Decisions (Director-approved)\\n\\n### BCE vs training-free: \\\"objective mismatch\\\" 非 \\\"anti-learning\\\" (2026-05-16)\\nBCE (54.84) 比 training-free (23-33) 差。**禁止用 \\\"anti-learning\\\" framing**，改用 **\\\"objective mismatch\\\"**：BCE 优化 per-neuron binary accuracy，TEAL 推理用 global top-k 重分配，两者结构性不兼容。BCE 学到的 per-neuron scoring 在 global budget allocation 下不是最优的。正确 claim: loss function 必须匹配推理管线的 sparsity allocation 机制。KL 直接优化 output distribution，天然兼容任何 allocation 策略。\\n\\n### KL PPL 统一引用规范 (2026-05-16)\\n论文中所有 KL PPL 对比统一用 **4-seed mean 12.00±0.07**（TEAL sparse PPL），不要用单 seed 最佳值 11.91。BCE iso-compute 对比时标注步数（1000 步 vs KL 1000 步，但 BCE per-step FLOPs 仅 KL 的 1/2.71）。\\n\\n### SPON framing: \\\"marginal complement\\\" 非 \\\"subsumption\\\" (2026-05-15)\\n禁止 \\\"KL subsumes SPON\\\" 措辞。正确表述：SPON corrections are orthogonal to and much smaller than predictor mask effects (cos_sim=0.196, magnitude ratio=16%)。D010 \\\"marginal complement\\\" framing。\\n\\n### s456 outlier 报告方式 (2026-05-16)\\n报 \\\"5-seed mean: 12.32±0.71\\\" + \\\"Excluding s456 (TEAL allocation outlier): 12.00±0.07\\\"。附 per-seed breakdown table + Layer 31 keep ratio 分析。不跑第 6 个 seed。\\n\\n## Key Insights (non-metrics)\\n\\n### 50% sparsity 摧毁 autoregressive generation (2026-05-16)\\nGSM8K 生成对比（10 samples）：sparse 50% 模型 1-3 句后进入无限重复循环，0/10 正确。退化模式是推理能力根本性丧失（模式 A），非仅数字算错。PPL 不惩罚 repetition loop（每个重复 token 仍有较高概率）。这解释了 PPL 12.00 但 GSM8K exact_match 仅 0.0121 的 disconnect。论文需用 30% 数据展示 sparsity-task tradeoff。\\n\\n### PPL-downstream disconnect 是真实现象，非 eval bug (2026-05-16)\\n三重验证确认：(1) acc_norm 已正确使用，(2) mask 逻辑审查无 bug（HFLM logit diff=0.0），(3) 生成对比显示推理链断裂。根因：50% sparsity 下 logit 微小偏移（如 \\\"Paris\\\" 从 #2 降到 #5）足以翻转 4-choice 答案，且摧毁 autoregressive 推理链。\\n\\n### PPL-downstream disconnect 文献支撑 (2026-05-16)\\n文献调研确认这是**已知但未充分研究**的现象。核心证据：(1) Khanal & Capone (2024): SparseGPT/Wanda 在 50% sparsity 保持 PPL 但下游退化，\\\"perplexity as sole evaluation metric is inadequate\\\"; (2) Xu et al. (2024, EMNLP): PPL 在 45-60% sparsity 前无变化但完全无法捕捉能力退化; (3) Kodathala & Vunnam (2026): N:M pruning 25-30% sparsity 下 factual QA 崩溃 97% 但 PPL 不变; (4) Siam et al. (2026): 定义 Type 2 trap（推理断裂后重复循环），与我们的 GSM8K 退化模式完全一致。**文献空白：无论文在 contextual sparsity predictor + KL distillation 下系统研究此现象。** 详细报告见 artifacts/literature_ppl_downstream_disconnect.md。\\n\\n### STE vs Gumbel: smooth gradient is essential for KL+Lagrangian training (2026-05-16)\\nSTE hard threshold causes violent lambda oscillation (range [0.01, 1000], overall std=354) because sigmoid→binary 翻转是离散的——微小参数变化可翻转大量 neuron，导致 constraint violation 剧烈跳变。后果：(1) per-token sparsity 仅 0.470（未达 target 0.50）, (2) 逐层稀疏度两极化（Layer 0-17: 5-56%, Layer 18-31: 56-90%）, (3) TEAL global 分配效果差（PPL 15.77 vs Gumbel 12.00）。Gumbel soft mask 提供连续梯度，lambda 平稳收敛到 cap，sparsity 精准收敛到 target。**Relaxation method 不是实现细节，是 KL distillation 训练稳定性的前提。**\\n\\n### KL predictor implicitly subsumes static correction (2026-05-15)\\nSPON bias vectors recover only 3.8% of sparse-vs-dense gap on top of KL predictor (PPL 9.22→9.10). Root cause: KL's end-to-end gradient already captures average-case AND per-input neuron importance through d_logits/dh * dh/dm coupling. Static bias correction is redundant when the contextual predictor is trained with output-distribution alignment.\\n\\n### SPON seq_len=2048 confirms subsumption, rules out mismatch confound (2026-05-15)\\nspon_2048_s42: training seq_len matched eval seq_len=2048. Recovery improved 3.8%→7.3% (+3.5pp), bias norm 0.041→0.053 (+30%), but still < 10% threshold. Even under matched conditions, static bias is fundamentally limited against KL predictor's per-token mask.\\n\\n### Compensation cannot fix BCE's fundamental flaw (2026-05-15)\\nBCE+Compensation (67.2M params, staged training) only improves per-token PPL by 9% (27.96→25.44), still 2.8x worse than KL-only (9.21). TEAL global path completely unaffected by comp network (44.54 = BCE-only). Root cause: BCE gradient dL/ds_j is per-neuron factorized.\\n\\n### Training-free baselines: per-layer normalization is critical (2026-05-16)\\nCRITICAL bug in _global_topk_masks: activation magnitudes vary 50-100x across layers. Fix: divide each layer's importance scores by layer mean before global topk. Corrected PPL: Vanilla TEAL 23.31, WINA 27.93, TEAL Greedy 33.47. R-Sparse still broken (SVD scores need percentile/max normalization). **Same bug likely affects predictor TEAL path** — sparsity70 TEAL PPL=136K anomaly.\\n\\n### BCE objective mismatch with TEAL inference (2026-05-16)\\nBCE iso-compute (1000 steps, reg_weight=2.0, sparsity=0.502) gets TEAL PPL=54.84 — worse than all 3 training-free baselines (23-33). Root cause: BCE optimizes per-neuron binary accuracy independently, but TEAL inference uses global top-k budget allocation across layers. Per-neuron scores optimized for binary accuracy are structurally incompatible with global budget allocation. KL directly optimizes output distribution, naturally compatible with any allocation strategy.\\n\\n### Hard-mask PPL vs TEAL sparse PPL variance separation (2026-05-15)\\n5-seed hard-mask PPL std = 0.04 (9.14-9.25), 极其稳定。TEAL sparse PPL std = 0.69 (11.91-13.58), 方差大 16 倍。方差来自 TEAL 全局分配算法与 per-token mask 的匹配度。\\n\\n### KL vs BCE per-step FLOPs ratio = 2.71x (2026-05-15)\\n实测 (BS=1, SL=512): KL 0.549s/step, BCE 0.202s/step。Iso-compute BCE 需要 2700 步 (= 1000 × 2.71) 匹配 KL 1000 步的总 FLOPs。\\n\\n### gradient_checkpointing 对 sparsity training 是必须的 (2026-05-15)\\n所有 LLaMA-3.1-8B sparsity 训练必须加 --gradient_checkpointing。不加则 OOM（>96GB），加了后 46.9-67.6GB。\\n\\n### BCE iso-compute sparsity 收敛需要 reg_weight=2.0 (2026-05-15)\\n原始 SparsityRegularizer 在 torch.no_grad() 下计算 mask，梯度为零。修复：STE hard mask + reg_weight=2.0。\\n\\n### lambda_max=1000 对低 sparsity target 不够 (2026-05-16)\\nsparsity30 (target=0.30) 两次 sparsity 卡在 0.281，lambda 撞 1000 cap。v3 用 lambda_max=5000。\\n\\n### Mistral-7B 与 Llama-3.1-8B 代码完全兼容 (2026-05-16)\\ntrain.py 零改动即可运行。架构一致。Predictor 参数量完全相同 (~75.96M)。vocab_size 差异只影响 KL loss logit 维度。\\n\\n## Checkpoints\\n- KL-only predictor (s42): `/root/distill_sparse_swiglu/checkpoints/mvp_kl_norm_v2_s42/predictor_kl_normalized.pt`\\n- SPON biases (seq128): `/root/distill_sparse_swiglu/checkpoints/spon_kl_s42/spon_biases.pt` (928KB)\\n- SPON biases (seq2048): `/root/distill_sparse_swiglu/checkpoints/spon_2048_s42/`\\n- BCE+comp predictor: `/root/distill_sparse_swiglu/checkpoints/bce_comp_staged_s42/predictor_bce_comp.pt`\\n- BCE iso-compute v2 (s42): `/root/distill_sparse_swiglu/checkpoints/bce_isocompute_v2_s42/`\\n- SPON eval script: `/root/distill_sparse_swiglu/src/eval_spon.py`\\n- Mistral-7B: `/root/autodl-tmp/models/mistral-7b/` (7.25B params, 14MB)\\n- KL sparsity70 (s42): `/root/distill_sparse_swiglu/checkpoints/kl_sparsity70_s42/predictor_kl_normalized.pt`\\n- KL sparsity30 v2 (s42): `/root/distill_sparse_swiglu/checkpoints/kl_sparsity30_s42/predictor_kl_normalized.pt` (sparsity=0.281, negative)\\n- KL sparsity30 v3 (s42): `/root/distill_sparse_swiglu/checkpoints/kl_sparsity30_s42_v3/predictor_kl_normalized.pt` (145MB)\\n- STE baseline (s42): `/root/distill_sparse_swiglu/checkpoints/ste_baseline_s42/`\\n\", \"total_chars\": 6933, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 11_

<details><summary>Logged reasoning block</summary>

```text
Now I have both the literature map and the memory. Let me also check if there's a paper_framing.md or writing_plan.yaml for additional context.

Let me now write the Related Work section. Key framing constraints from memory.md:
1. BCE vs training-free: use "objective mismatch" framing, NOT "anti-learning"
2. SPON framing: "marginal complement" NOT "subsumption"
3. PPL-downstream disconnect is a real phenomenon

Let me organize the Related Work based on the user's grouping instructions:

**Structure (far → near):**


1. Training-free Activation Sparsity (background, furthest)
2. Learned Sparsity Predictors with BCE (direct comparison)
3. Static Correction / KL for Sparsity (closest, most relevant)

I need to double-check the user's grouping since they emphasized "最相关放最后" (most relevant last), and I want to make sure I'm ordering these correctly with PPL-Downstream Disconnect positioned appropriately as analytical background. I'm reconsidering the organization based on the two-axis taxonomy—correction granularity and training signal coupling. The most related work should align with both axes, so I'll order from least to most related: training-free sparsity as background, then the PPL-downstream analysis, KL distillation for compression, learned predictors with per-neuron objectives as direct competitors, and finally distribution-coupled sparsity training as the closest work since it combines both the KL and sparsity dimensions.

Now I'm drafting the related work section and gathering the key citations I'll need.

Let me organize this into subsections covering training-free activation sparsity, structured pruning approaches, and activation function research, keeping each paper to just a sentence or two and aiming for about a page and a half total. I'm reconsidering the section order to put the most relevant work last. The PPL-downstream disconnect feels tangential compared to the core comparisons, so I'll reorganize around what directly relates to our contribution: starting with training-free methods as background, then KL distillation techniques, then learned predictors with their objective mismatch, and finally SPON which combines KL with sparsity—the closest existing work to what we're doing. I can see the taxonomy provides a useful framework for organizing these methods. Now I'm drafting the Related Work section, starting with training-free activation sparsity approaches—covering various magnitude-based and rank-aware pruning techniques like TEAL, WINA, R-Sparse, CATS, and Amber Pruner, which use different scoring mechanisms and sparsity patterns across layers.

The key limitation of these training-free methods is that they rely on fixed scoring criteria that can't adapt to input-specific neuron importance, resulting in substantial quality loss at moderate sparsity levels—TEAL, the best performer, still suffers a perplexity increase of over 6 points at 50% sparsity on Llama-3.1-8B.

Moving to KL distillation, I'm noting that forward KL divergence has become a standard tool for recovering quality after structural compression, with Minitron showing that logit-only KL distillation outperforms cross-entropy and intermediate-layer matching for pruning recovery by better preserving inter-token distributional relationships.

Recent work has extended this—some approaches train input-dependent mask predictors for instruction-aware pruning using KL as a selection criterion, establishing it as the preferred objective for distribution-preserving compression, though no one has yet applied KL to train activation sparsity predictors.

On the predictor side, DejaVu introduced lightweight MLP predictors trained with binary cross-entropy to identify skippable neurons and attention heads, achieving 2× speedup on OPT-175B, while ShadowLLM improved on this with context-dependent importance scoring, gaining 15% accuracy over DejaVu.

FastForward pushed further by augmenting the BCE-trained predictor with an error compensation network and layer-wise sparsity scheduler to reach 1.45× prefill acceleration at 50% sparsity. The core limitation across all three methods is that their per-neuron binary classification objectives prevent the predictor from learning how neurons interact jointly to shape the output distribution—FastForward's compensation network partially addresses this but adds inference overhead. I'm realizing that switching from BCE to KL divergence could eliminate the need for compensation entirely.

SPON appears to be the closest precedent to what I'm working on, training input-independent learnable sparsity patterns.

SPON trains learnable bias vectors using KL divergence between dense and sparse output distributions, achieving zero-inference-overhead correction by absorbing the biases into model parameters. But static biases can't adapt to how neuron importance varies per input. Looking at the experimental results, SPON's corrections are nearly orthogonal to the predictor mask effects and substantially smaller in magnitude—they recover less than 10% of the performance gap when applied on top of a KL-trained predictor. My approach fills the remaining gap in the correction taxonomy by combining per-token contextual prediction with distribution-coupled training, merging SPON's distribution-level objective with input-dependent prediction.

Now I'm examining how perplexity fails to capture the actual capability degradation in sparse models. Multiple studies show that perplexity can remain stable even as downstream performance collapses—at 50% weight or activation sparsity, models maintain near-baseline perplexity while accuracy on reasoning tasks plummets. There's even a specific failure mode where reasoning chains break and the model gets stuck in repetitive loops, something perplexity can't detect by design. I'm seeing this exact pattern in my experiments with Llama-3.1-8B at 50% activation sparsity, which is why I'm using a multi-metric evaluation approach rather than relying on perplexity alone.

I'm checking the length now—roughly 35 lines across 5 paragraphs should fit within the page budget. I need to make sure the writing is clean: no hedging phrases, no AI-sounding language, and the framing aligns with how I've positioned the work. I'm also verifying the citation keys are descriptive and consistent, then I'll finalize the document.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "75b66027-5950-4574-b07b-684f9b5c1cc2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PqmwmvQetaW1LNjbpanmBD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10135,
      "cache_read_input_tokens": 24757,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10135
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 12_

Now let me check the target directory structure and write the Related Work section.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "e7b26d1c-b06a-4709-b1c4-a152fee6a8a5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PqmwmvQetaW1LNjbpanmBD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10135,
      "cache_read_input_tokens": 24757,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10135
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 13_

<details open><summary>🔧 Tool call — Bash · `toolu_01KXBgoHYoPafXf3e7UXdf4d`</summary>

```json
{
  "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/_project/paper/ 2>/dev/null || echo \"DIR_NOT_EXISTS\"",
  "description": "Check paper directory existence"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "9edfb7f2-49ee-41a8-94fd-7c5763f91413",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PqmwmvQetaW1LNjbpanmBD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10135,
      "cache_read_input_tokens": 24757,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10135
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-16T02:28:09.744Z_

<details><summary>↩ Tool result · `toolu_01KXBgoHYoPafXf3e7UXdf4d`</summary>

```text
total 40
drwxr-xr-x 2 ubuntu ubuntu  4096 May 16 02:27 .
drwxr-xr-x 7 ubuntu ubuntu  4096 May 16 02:26 ..
-rw-r--r-- 1 ubuntu ubuntu 12646 May 16 02:27 methodology.tex
-rw-r--r-- 1 ubuntu ubuntu 12646 May 16 02:27 methodology_6e294a.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "7cbc5369-7fe6-48fa-9f11-d1d74b03d0f7",
  "tool_use_result": {
    "stdout": "total 40\ndrwxr-xr-x 2 ubuntu ubuntu  4096 May 16 02:27 .\ndrwxr-xr-x 7 ubuntu ubuntu  4096 May 16 02:26 ..\n-rw-r--r-- 1 ubuntu ubuntu 12646 May 16 02:27 methodology.tex\n-rw-r--r-- 1 ubuntu ubuntu 12646 May 16 02:27 methodology_6e294a.tex",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 15_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01LkS3P4nK8AiAbR13MD92cE`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__save_project_file",
  "max_results": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "899f378b-d24d-4ac6-adb4-b537ea4cbb18",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MvS1tzQeGaN4oKeDGDwyUX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3563,
      "cache_read_input_tokens": 34892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3563
      },
      "output_tokens": 34,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-16T02:28:16.124Z_

<details><summary>↩ Tool result · `toolu_01LkS3P4nK8AiAbR13MD92cE`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__save_project_file"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "e1a40f0e-6577-48be-83fa-ef92c463c78a",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file"
    ],
    "query": "select:mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__save_project_file",
    "total_deferred_tools": 25
  }
}
```

</details>

---

### Assistant

_source line 17_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the context I need. Let me write the Related Work section. Let me carefully craft it based on:

1. The literature map
2. The memory framing constraints:
   - BCE framing: "objective mismatch" not "anti-learning"
   - SPON framing: "marginal complement" not "subsumption"
   - PPL-downstream disconnect is real
3. The taxonomy from the user's prompt
4. Keep to 1-1.5 pages, each paper 1-2 sentences

Let me write the LaTeX now.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "b264c1ea-eb57-4afa-9191-536b88c130cb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01P8eMUaqi6bcDY3FYwjR49U",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 976,
      "cache_read_input_tokens": 38455,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 976
      },
      "output_tokens": 22,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 18_

<details open><summary>🔧 Tool call — Write · `toolu_018Uf2DtHY4eiVagSduvM5vw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/_project/paper/related_work.tex",
  "content": "\\section{Related Work}\n\\label{sec:related}\n\nPrior approaches to activation sparsity in LLMs vary along two axes: \\emph{correction granularity} (static, per-layer, or per-token contextual) and \\emph{training signal coupling} (decomposed per-neuron objectives, intermediate representations, or coupled output distributions). We survey each regime below and position our method in the resulting taxonomy (Table~\\ref{tab:taxonomy}).\n\n\\paragraph{Training-Free Activation Sparsity.}\nA family of methods prune activations at inference time without learned parameters.\nTEAL~\\cite{liu2025teal} applies magnitude-based thresholding across hidden states, achieving 1.8$\\times$ decoding speedup at 50\\% sparsity on ReLU models but degrading substantially on SwiGLU architectures.\nWINA~\\cite{wina2025} incorporates weight magnitudes into importance scoring, and R-Sparse~\\cite{zhang2025rsparse} derives rank-aware scores via SVD.\nCATS~\\cite{lee2024cats} computes per-layer percentile thresholds on SiLU activations.\nAmber Pruner~\\cite{an2025amber} enforces hardware-friendly N:M structured patterns, and DIP~\\cite{federici2025dip} applies dynamic magnitude pruning directly to SwiGLU layers with LoRA-based recovery.\nThese methods avoid training costs but rely on fixed scoring criteria that cannot adapt to per-input neuron importance.\nOn Llama-3.1-8B at 50\\% sparsity, even the best training-free method incurs a perplexity gap exceeding 6 points.\n\n\\paragraph{KL Distillation for Model Compression.}\nForward KL divergence has proven effective for recovering quality after structural compression.\nMinitron~\\cite{muralidharan2024minitron} shows that logit-only KL distillation outperforms both cross-entropy and intermediate-layer matching for structured pruning recovery, attributing this to preservation of inter-token distributional relationships.\n\\citet{hou2025ifp} train input-dependent mask predictors for instruction-aware weight pruning, and \\citet{distill2025hybrid} use per-layer KL as a selection criterion for hybrid attention architectures.\nThese results establish KL as the preferred objective for distribution-preserving compression, yet no prior work applies KL to train activation sparsity predictors.\n\n\\paragraph{Learned Contextual Sparsity Predictors.}\nDejaVu~\\cite{liu2023dejavu} introduces lightweight MLP predictors trained with binary cross-entropy (BCE) to identify skippable neurons and attention heads, achieving 2$\\times$ speedup on OPT-175B.\nShadowLLM~\\cite{akhauri2024shadowllm} improves predictor architectures with per-layer MSE distillation of intermediate representations, reporting 15\\% accuracy gains over DejaVu.\nFastForward~\\cite{gautam2026fastforward} augments a BCE-trained predictor with a 67.2M-parameter error compensation network and a layer-wise sparsity scheduler, reaching 1.45$\\times$ prefill acceleration at 50\\% sparsity.\nAll three methods optimize per-neuron objectives whose gradients factorize across neurons, preventing the predictor from capturing how joint neuron interactions shape the output distribution.\nThis creates an objective mismatch: predictors trained for per-neuron binary accuracy produce scores that are structurally incompatible with inference-time global budget allocation~\\cite{liu2025teal}.\nFastForward's compensation network partially addresses this gap but adds inference overhead; we show that replacing the per-neuron objective with KL divergence eliminates the need for compensation entirely.\n\n\\paragraph{Distribution-Coupled Sparsity Correction.}\nSPON~\\cite{xu2026spon} is the closest precedent: it trains input-independent learnable bias vectors via KL divergence between dense and sparse output logits, then absorbs the biases into model parameters for zero-inference-overhead correction.\nSPON demonstrates that KL is well-suited for sparsity-aware distribution matching.\nHowever, static biases cannot adapt to per-input variation in neuron importance.\nIn our experiments, SPON corrections are orthogonal to and substantially smaller than contextual predictor mask effects (cosine similarity 0.196, magnitude ratio 16\\%), recovering less than 10\\% of the sparse-to-dense gap when applied on top of a KL-trained predictor.\nOur method fills the remaining cell in the granularity$\\times$coupling taxonomy: per-token contextual prediction with a coupled KL objective, combining SPON's distribution-level training signal with DejaVu's input-dependent prediction.\n\n\\paragraph{Perplexity--Downstream Disconnect.}\nSeveral studies document that perplexity inadequately captures capability degradation in sparse models.\n\\citet{khanal2024ppl} show that SparseGPT and Wanda at 50\\% weight sparsity maintain perplexity while downstream accuracy degrades significantly.\n\\citet{xu2024sparsity} observe that perplexity remains flat up to 45--60\\% activation sparsity yet fails to reflect emerging capability loss.\n\\citet{siam2026type2} characterize a Type~2 failure mode---reasoning chain breakage followed by repetitive cycling---that perplexity by construction cannot penalize.\nWe observe the same pattern: at 50\\% activation sparsity, Llama-3.1-8B achieves near-baseline perplexity but collapses on chain-of-thought tasks, motivating our multi-metric evaluation beyond perplexity alone.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "cccb9a52-f0ca-49fa-bfea-a7ae4247c1f0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01P8eMUaqi6bcDY3FYwjR49U",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 976,
      "cache_read_input_tokens": 38455,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 976
      },
      "output_tokens": 22,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 19 · 2026-05-16T02:29:02.298Z_

<details><summary>↩ Tool result · `toolu_018Uf2DtHY4eiVagSduvM5vw`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/_project/paper/related_work.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "8e0964ed-9e65-45d9-9092-6fe468eb92fc",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/_project/paper/related_work.tex",
    "content": "\\section{Related Work}\n\\label{sec:related}\n\nPrior approaches to activation sparsity in LLMs vary along two axes: \\emph{correction granularity} (static, per-layer, or per-token contextual) and \\emph{training signal coupling} (decomposed per-neuron objectives, intermediate representations, or coupled output distributions). We survey each regime below and position our method in the resulting taxonomy (Table~\\ref{tab:taxonomy}).\n\n\\paragraph{Training-Free Activation Sparsity.}\nA family of methods prune activations at inference time without learned parameters.\nTEAL~\\cite{liu2025teal} applies magnitude-based thresholding across hidden states, achieving 1.8$\\times$ decoding speedup at 50\\% sparsity on ReLU models but degrading substantially on SwiGLU architectures.\nWINA~\\cite{wina2025} incorporates weight magnitudes into importance scoring, and R-Sparse~\\cite{zhang2025rsparse} derives rank-aware scores via SVD.\nCATS~\\cite{lee2024cats} computes per-layer percentile thresholds on SiLU activations.\nAmber Pruner~\\cite{an2025amber} enforces hardware-friendly N:M structured patterns, and DIP~\\cite{federici2025dip} applies dynamic magnitude pruning directly to SwiGLU layers with LoRA-based recovery.\nThese methods avoid training costs but rely on fixed scoring criteria that cannot adapt to per-input neuron importance.\nOn Llama-3.1-8B at 50\\% sparsity, even the best training-free method incurs a perplexity gap exceeding 6 points.\n\n\\paragraph{KL Distillation for Model Compression.}\nForward KL divergence has proven effective for recovering quality after structural compression.\nMinitron~\\cite{muralidharan2024minitron} shows that logit-only KL distillation outperforms both cross-entropy and intermediate-layer matching for structured pruning recovery, attributing this to preservation of inter-token distributional relationships.\n\\citet{hou2025ifp} train input-dependent mask predictors for instruction-aware weight pruning, and \\citet{distill2025hybrid} use per-layer KL as a selection criterion for hybrid attention architectures.\nThese results establish KL as the preferred objective for distribution-preserving compression, yet no prior work applies KL to train activation sparsity predictors.\n\n\\paragraph{Learned Contextual Sparsity Predictors.}\nDejaVu~\\cite{liu2023dejavu} introduces lightweight MLP predictors trained with binary cross-entropy (BCE) to identify skippable neurons and attention heads, achieving 2$\\times$ speedup on OPT-175B.\nShadowLLM~\\cite{akhauri2024shadowllm} improves predictor architectures with per-layer MSE distillation of intermediate representations, reporting 15\\% accuracy gains over DejaVu.\nFastForward~\\cite{gautam2026fastforward} augments a BCE-trained predictor with a 67.2M-parameter error compensation network and a layer-wise sparsity scheduler, reaching 1.45$\\times$ prefill acceleration at 50\\% sparsity.\nAll three methods optimize per-neuron objectives whose gradients factorize across neurons, preventing the predictor from capturing how joint neuron interactions shape the output distribution.\nThis creates an objective mismatch: predictors trained for per-neuron binary accuracy produce scores that are structurally incompatible with inference-time global budget allocation~\\cite{liu2025teal}.\nFastForward's compensation network partially addresses this gap but adds inference overhead; we show that replacing the per-neuron objective with KL divergence eliminates the need for compensation entirely.\n\n\\paragraph{Distribution-Coupled Sparsity Correction.}\nSPON~\\cite{xu2026spon} is the closest precedent: it trains input-independent learnable bias vectors via KL divergence between dense and sparse output logits, then absorbs the biases into model parameters for zero-inference-overhead correction.\nSPON demonstrates that KL is well-suited for sparsity-aware distribution matching.\nHowever, static biases cannot adapt to per-input variation in neuron importance.\nIn our experiments, SPON corrections are orthogonal to and substantially smaller than contextual predictor mask effects (cosine similarity 0.196, magnitude ratio 16\\%), recovering less than 10\\% of the sparse-to-dense gap when applied on top of a KL-trained predictor.\nOur method fills the remaining cell in the granularity$\\times$coupling taxonomy: per-token contextual prediction with a coupled KL objective, combining SPON's distribution-level training signal with DejaVu's input-dependent prediction.\n\n\\paragraph{Perplexity--Downstream Disconnect.}\nSeveral studies document that perplexity inadequately captures capability degradation in sparse models.\n\\citet{khanal2024ppl} show that SparseGPT and Wanda at 50\\% weight sparsity maintain perplexity while downstream accuracy degrades significantly.\n\\citet{xu2024sparsity} observe that perplexity remains flat up to 45--60\\% activation sparsity yet fails to reflect emerging capability loss.\n\\citet{siam2026type2} characterize a Type~2 failure mode---reasoning chain breakage followed by repetitive cycling---that perplexity by construction cannot penalize.\nWe observe the same pattern: at 50\\% activation sparsity, Llama-3.1-8B achieves near-baseline perplexity but collapses on chain-of-thought tasks, motivating our multi-metric evaluation beyond perplexity alone.\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
```

</details>

---

### Tool call

_source line 20_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_01RQeRuLHqqwbX2jsyn2tyrW`</summary>

```json
{
  "name": "related_work",
  "type": "paper",
  "description": "Related Work section draft for KL distillation sparse SwiGLU paper (EMNLP 2026 ARR May)",
  "project": "distill_sparse_swiglu",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/_project/paper/related_work.tex",
  "tags": [
    "paper",
    "related-work",
    "latex"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "7dd2b3dc-6e09-48c6-8741-974dbfe08615",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019qFAQBKr4epyKhA8HE51QH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1672,
      "cache_read_input_tokens": 39431,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1672
      },
      "output_tokens": 59,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-16T02:29:07.276Z_

<details><summary>↩ Tool result · `toolu_01RQeRuLHqqwbX2jsyn2tyrW`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260516_c10e4f\", \"name\": \"related_work\", \"type\": \"paper\", \"description\": \"Related Work section draft for KL distillation sparse SwiGLU paper (EMNLP 2026 ARR May)\", \"path\": \"projects/distill_sparse_swiglu/artifacts/_project/paper/related_work_c10e4f.tex\", \"url\": null, \"project\": \"distill_sparse_swiglu\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-16T02:29:07.214206+00:00\", \"tags\": [\"paper\", \"related-work\", \"latex\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "657a4799-813c-43f5-bdb9-ceddb54e3126",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260516_c10e4f\\\", \\\"name\\\": \\\"related_work\\\", \\\"type\\\": \\\"paper\\\", \\\"description\\\": \\\"Related Work section draft for KL distillation sparse SwiGLU paper (EMNLP 2026 ARR May)\\\", \\\"path\\\": \\\"projects/distill_sparse_swiglu/artifacts/_project/paper/related_work_c10e4f.tex\\\", \\\"url\\\": null, \\\"project\\\": \\\"distill_sparse_swiglu\\\", \\\"exp_id\\\": null, \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-16T02:29:07.214206+00:00\\\", \\\"tags\\\": [\\\"paper\\\", \\\"related-work\\\", \\\"latex\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260516_c10e4f\", \"name\": \"related_work\", \"type\": \"paper\", \"description\": \"Related Work section draft for KL distillation sparse SwiGLU paper (EMNLP 2026 ARR May)\", \"path\": \"projects/distill_sparse_swiglu/artifacts/_project/paper/related_work_c10e4f.tex\", \"url\": null, \"project\": \"distill_sparse_swiglu\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-16T02:29:07.214206+00:00\", \"tags\": [\"paper\", \"related-work\", \"latex\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 22_

```json
{
  "artifact_id": "art_20260516_c10e4f",
  "file": "artifacts/_project/paper/related_work.tex",
  "sections": 5,
  "structure": [
    {"paragraph": "Training-Free Activation Sparsity", "papers": ["TEAL", "WINA", "R-Sparse", "CATS", "Amber Pruner", "DIP"], "role": "background"},
    {"paragraph": "KL Distillation for Model Compression", "papers": ["Minitron", "Instruction-Following Pruning", "KL-guided hybrid attention"], "role": "method_background"},
    {"paragraph": "Learned Contextual Sparsity Predictors", "papers": ["DejaVu", "ShadowLLM", "FastForward"], "role": "direct_comparison"},
    {"paragraph": "Distribution-Coupled Sparsity Correction", "papers": ["SPON"], "role": "closest_prior_work"},
    {"paragraph": "Perplexity--Downstream Disconnect", "papers": ["Khanal & Capone 2024", "Xu et al. 2024", "Siam et al. 2026"], "role": "evaluation_motivation"}
  ],
  "estimated_length_pages": 1.2,
  "taxonomy_referenced": true,
  "framing_constraints_applied": {
    "BCE_as_objective_mismatch": true,
    "SPON_as_marginal_complement": true,
    "no_first_to_claim": true
  },
  "placeholder_citekeys": [
    "liu2025teal", "wina2025", "zhang2025rsparse", "lee2024cats",
    "an2025amber", "federici2025dip", "muralidharan2024minitron",
    "hou2025ifp", "distill2025hybrid", "liu2023dejavu",
    "akhauri2024shadowllm", "gautam2026fastforward", "xu2026spon",
    "khanal2024ppl", "xu2024sparsity", "siam2026type2"
  ]
}
```

5 段落，覆盖 16 篇文献，约 1.2 页。核心 framing 约束已全部遵守：BCE 用 "objective mismatch"，SPON 用 "orthogonal to and substantially smaller than"（marginal complement），无 "first to" 声明。Taxonomy 在开头段引用并在 SPON 段闭合（"fills the remaining cell"）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "uuid": "30011e35-ae5f-4483-907d-6a93cab0b27b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HoQBnjsJBr36aY9qAosc61",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 517,
      "cache_read_input_tokens": 41103,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 517
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Task result

_source line 23_

```json
{
  "artifact_id": "art_20260516_c10e4f",
  "file": "artifacts/_project/paper/related_work.tex",
  "sections": 5,
  "structure": [
    {"paragraph": "Training-Free Activation Sparsity", "papers": ["TEAL", "WINA", "R-Sparse", "CATS", "Amber Pruner", "DIP"], "role": "background"},
    {"paragraph": "KL Distillation for Model Compression", "papers": ["Minitron", "Instruction-Following Pruning", "KL-guided hybrid attention"], "role": "method_background"},
    {"paragraph": "Learned Contextual Sparsity Predictors", "papers": ["DejaVu", "ShadowLLM", "FastForward"], "role": "direct_comparison"},
    {"paragraph": "Distribution-Coupled Sparsity Correction", "papers": ["SPON"], "role": "closest_prior_work"},
    {"paragraph": "Perplexity--Downstream Disconnect", "papers": ["Khanal & Capone 2024", "Xu et al. 2024", "Siam et al. 2026"], "role": "evaluation_motivation"}
  ],
  "estimated_length_pages": 1.2,
  "taxonomy_referenced": true,
  "framing_constraints_applied": {
    "BCE_as_objective_mismatch": true,
    "SPON_as_marginal_complement": true,
    "no_first_to_claim": true
  },
  "placeholder_citekeys": [
    "liu2025teal", "wina2025", "zhang2025rsparse", "lee2024cats",
    "an2025amber", "federici2025dip", "muralidharan2024minitron",
    "hou2025ifp", "distill2025hybrid", "liu2023dejavu",
    "akhauri2024shadowllm", "gautam2026fastforward", "xu2026spon",
    "khanal2024ppl", "xu2024sparsity", "siam2026type2"
  ]
}
```

5 段落，覆盖 16 篇文献，约 1.2 页。核心 framing 约束已全部遵守：BCE 用 "objective mismatch"，SPON 用 "orthogonal to and substantially smaller than"（marginal complement），无 "first to" 声明。Taxonomy 在开头段引用并在 SPON 段闭合（"fills the remaining cell"）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 164744,
  "duration_api_ms": 165540,
  "num_turns": 8,
  "stop_reason": "end_turn",
  "session_id": "4945e587-b3e4-4aee-bb75-bd1a9d09ac81",
  "total_cost_usd": 0.45477875,
  "usage": {
    "input_tokens": 12,
    "cache_creation_input_tokens": 29779,
    "cache_read_input_tokens": 214782,
    "output_tokens": 6353,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 29779,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 657,
        "cache_read_input_tokens": 41103,
        "cache_creation_input_tokens": 517,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 517
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2279,
      "outputTokens": 21,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0023840000000000003,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 12,
      "outputTokens": 6353,
      "cacheReadInputTokens": 214782,
      "cacheCreationInputTokens": 29779,
      "webSearchRequests": 0,
      "costUSD": 0.45239475,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "274f336b-b490-46da-b608-6df9d62f8fea"
}
```

</details>

---
