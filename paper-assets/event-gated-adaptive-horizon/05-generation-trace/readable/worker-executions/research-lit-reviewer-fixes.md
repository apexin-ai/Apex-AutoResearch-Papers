# research lit reviewer fixes

**Why Temporal Abstraction Can Fail in Imagination-Based RL: A Diagnostic Analysis of Variable-Rate DreamerV3** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 50
- **Recorded user turns:** 0
- **Tool calls:** 18
- **Original source:** `logs/workers/worker_research_lit-reviewer-fixes_20260514T145621.log`
- **Structured JSON:** [`389dfd902286f6e8ae12.json`](../../sessions/38/389dfd902286f6e8ae12.json)

## Before a recorded user message

50 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon",
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
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
    "mcp__agent-ml-research__save_project_file"
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
  "uuid": "5f6001a5-d525-4aa4-82a0-b74f25fe0568",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-9-projects-event-gated-adaptive-horizon/memory/"
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
    "resetsAt": 1778778000,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "186bb9e4-116c-45dc-9c7a-499e6f54e81b",
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a"
}
```

---

### Assistant

_source line 4_

I'll start by reading the current literature_map.yaml and searching for the two new papers in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "93f7f772-91c2-49c5-a307-045bea9cf6e5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C7WxVoYpcYbULYd5v1xdnv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11830,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11830
      },
      "output_tokens": 4,
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01NQaEfnivA5TqYneAChqXki`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file,WebSearch",
  "max_results": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "72ed76e6-c32e-4beb-a79f-dec3a031d770",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C7WxVoYpcYbULYd5v1xdnv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11830,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11830
      },
      "output_tokens": 4,
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

_source line 6 · 2026-05-14T14:56:35.248Z_

<details><summary>↩ Tool result · `toolu_01NQaEfnivA5TqYneAChqXki`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_project_file"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__save_project_file"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "WebSearch"
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
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "5aac2d28-88e7-489e-9b0c-51aefec7958f",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__save_project_file",
      "WebSearch"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file,WebSearch",
    "total_deferred_tools": 22
  }
}
```

</details>

---

### Assistant

_source line 7_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the literature_map.yaml and search for the two papers in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "30c88f19-4854-411e-82c8-5ecd1492c830",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Hj9jmguPnxyr2PTuC1KNzn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1225,
      "cache_read_input_tokens": 23277,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1225
      },
      "output_tokens": 43,
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

_source line 8_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01TEgVJrRzAV5VeUjcEyKgYx`</summary>

```json
{
  "project": "event-gated-adaptive-horizon",
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
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "5000b863-e1bb-4dfb-97aa-0201396226f6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Hj9jmguPnxyr2PTuC1KNzn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1225,
      "cache_read_input_tokens": 23277,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1225
      },
      "output_tokens": 43,
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

_source line 9 · 2026-05-14T14:56:38.607Z_

<details><summary>↩ Tool result · `toolu_01TEgVJrRzAV5VeUjcEyKgYx`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml\", \"content\": \"# Literature Map — event-gated-adaptive-horizon\\n# Last updated: 2026-05-14\\n# Total: 43 papers (5 existing + 38 new)\\n\\n# ============================================================\\n# EXISTING CITATIONS (already in paper.tex)\\n# ============================================================\\n\\n- paper_id: sutton1999options\\n  title: \\\"Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning\\\"\\n  authors: [Sutton R.S., Precup D., Singh S.]\\n  year: 1999\\n  venue: \\\"Artificial Intelligence 112(1-2):181-211\\\"\\n  category: background\\n  role: \\\"Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL\\\"\\n  relevance_score: 5\\n\\n- paper_id: hafner2020dreamerv1\\n  title: \\\"Dream to Control: Learning Behaviors by Latent Imagination\\\"\\n  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]\\n  year: 2020\\n  venue: ICLR\\n  category: background\\n  role: \\\"DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm\\\"\\n  relevance_score: 5\\n\\n- paper_id: hafner2023dreamerv3\\n  title: \\\"Mastering Diverse Domains through World Models\\\"\\n  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]\\n  year: 2023\\n  venue: \\\"arXiv:2301.04104 (Nature 2025)\\\"\\n  category: background\\n  role: \\\"DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here\\\"\\n  relevance_score: 5\\n\\n- paper_id: sharma2017figar\\n  title: \\\"Fine Grained Action Repetition for Deep Reinforcement Learning\\\"\\n  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]\\n  year: 2017\\n  venue: \\\"ICLR Workshop\\\"\\n  category: method-component\\n  role: \\\"FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL\\\"\\n  relevance_score: 4\\n\\n- paper_id: janner2019mbpo\\n  title: \\\"When to Trust Your Model: Model-Based Policy Optimization\\\"\\n  authors: [Janner M., Fu J., Zhang M., Levine S.]\\n  year: 2019\\n  venue: NeurIPS\\n  category: background\\n  role: \\\"MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding\\\"\\n  relevance_score: 5\\n\\n# ============================================================\\n# NEW: Multi-step prediction error compounding\\n# ============================================================\\n\\n- paper_id: ke2019learning\\n  title: \\\"Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future\\\"\\n  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]\\n  year: 2019\\n  venue: ICLR\\n  category: background\\n  role: \\\"Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1\\\"\\n  relevance_score: 4\\n\\n- paper_id: asadi2019combating\\n  title: \\\"Combating the Compounding-Error Problem with a Multi-step Model\\\"\\n  authors: [Asadi K., Misra D., Kim S., Littman M.L.]\\n  year: 2019\\n  venue: \\\"arXiv:1905.13320\\\"\\n  category: background\\n  role: \\\"Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error\\\"\\n  relevance_score: 4\\n\\n- paper_id: venkatraman2015improving\\n  title: \\\"Improving Multi-Step Prediction of Learned Time Series Models\\\"\\n  authors: [Venkatraman A., Hebert M., Bagnell J.A.]\\n  year: 2015\\n  venue: AAAI\\n  category: background\\n  role: \\\"Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error\\\"\\n  relevance_score: 3\\n\\n- paper_id: lambert2022investigating\\n  title: \\\"Investigating Compounding Prediction Errors in Learned Dynamics Models\\\"\\n  authors: [Lambert N., Pister K.S.J., Calandra R.]\\n  year: 2022\\n  venue: \\\"arXiv:2203.09637\\\"\\n  category: background\\n  role: \\\"Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Model-predictive control with learned dynamics\\n# ============================================================\\n\\n- paper_id: chua2018pets\\n  title: \\\"Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models\\\"\\n  authors: [Chua K., Calandra R., McAllister R., Levine S.]\\n  year: 2018\\n  venue: NeurIPS\\n  category: background\\n  role: \\\"PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach\\\"\\n  relevance_score: 3\\n\\n- paper_id: nagabandi2018neural\\n  title: \\\"Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning\\\"\\n  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]\\n  year: 2018\\n  venue: ICRA\\n  category: background\\n  role: \\\"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Value overestimation mitigation\\n# ============================================================\\n\\n- paper_id: thrun1993issues\\n  title: \\\"Issues in Using Function Approximation for Reinforcement Learning\\\"\\n  authors: [Thrun S., Schwartz A.]\\n  year: 1993\\n  venue: \\\"Connectionist Models Summer School\\\"\\n  category: background\\n  role: \\\"First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning\\\"\\n  relevance_score: 4\\n\\n- paper_id: vanhasselt2016double\\n  title: \\\"Deep Reinforcement Learning with Double Q-Learning\\\"\\n  authors: [van Hasselt H., Guez A., Silver D.]\\n  year: 2016\\n  venue: AAAI\\n  category: background\\n  role: \\\"Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL\\\"\\n  relevance_score: 4\\n\\n- paper_id: fujimoto2018td3\\n  title: \\\"Addressing Function Approximation Error in Actor-Critic Methods\\\"\\n  authors: [Fujimoto S., van Hoof H., Meger D.]\\n  year: 2018\\n  venue: ICML\\n  category: method-component\\n  role: \\\"TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify\\\"\\n  relevance_score: 4\\n\\n- paper_id: haarnoja2018sac\\n  title: \\\"Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor\\\"\\n  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]\\n  year: 2018\\n  venue: ICML\\n  category: method-component\\n  role: \\\"SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values\\\"\\n  relevance_score: 3\\n\\n- paper_id: lee2021sunrise\\n  title: \\\"SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning\\\"\\n  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]\\n  year: 2021\\n  venue: ICML\\n  category: method-component\\n  role: \\\"Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Delusional bias\\n# ============================================================\\n\\n- paper_id: lu2018nondelusional\\n  title: \\\"Non-delusional Q-learning and Value-Iteration\\\"\\n  authors: [Lu T., Schuurmans D., Boutilier C.]\\n  year: 2018\\n  venue: NeurIPS\\n  category: background\\n  role: \\\"Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision\\\"\\n  relevance_score: 5\\n\\n# ============================================================\\n# NEW: Hierarchical RL with learned models\\n# ============================================================\\n\\n- paper_id: hafner2022director\\n  title: \\\"Deep Hierarchical Planning from Pixels\\\"\\n  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]\\n  year: 2022\\n  venue: NeurIPS\\n  category: direct-competitor\\n  role: \\\"Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt\\\"\\n  relevance_score: 4\\n\\n- paper_id: nachum2018hiro\\n  title: \\\"Data-Efficient Hierarchical Reinforcement Learning\\\"\\n  authors: [Nachum O., Gu S., Lee H., Levine S.]\\n  year: 2018\\n  venue: NeurIPS\\n  category: background\\n  role: \\\"HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Action repeat / frame skip\\n# ============================================================\\n\\n- paper_id: braylan2015frame\\n  title: \\\"Frame Skip Is a Powerful Parameter for Learning to Play Atari\\\"\\n  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]\\n  year: 2015\\n  venue: \\\"AAAI Workshop on Learning for General Competency in Video Games\\\"\\n  category: background\\n  role: \\\"Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice\\\"\\n  relevance_score: 3\\n\\n- paper_id: lakshminarayanan2017dynamic\\n  title: \\\"Dynamic Action Repetition for Deep Reinforcement Learning\\\"\\n  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]\\n  year: 2017\\n  venue: AAAI\\n  category: method-component\\n  role: \\\"Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach\\\"\\n  relevance_score: 4\\n\\n- paper_id: biedenkapp2021temporl\\n  title: \\\"TempoRL: Learning When to Act\\\"\\n  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]\\n  year: 2021\\n  venue: ICML\\n  category: method-component\\n  role: \\\"Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify\\\"\\n  relevance_score: 4\\n\\n# ============================================================\\n# NEW: DreamerV2\\n# ============================================================\\n\\n- paper_id: hafner2021dreamerv2\\n  title: \\\"Mastering Atari with Discrete World Models\\\"\\n  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]\\n  year: 2021\\n  venue: ICLR\\n  category: background\\n  role: \\\"DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system\\\"\\n  relevance_score: 5\\n\\n# ============================================================\\n# NEW: Alternative world model architectures\\n# ============================================================\\n\\n- paper_id: micheli2023iris\\n  title: \\\"Transformers are Sample-Efficient World Models\\\"\\n  authors: [Micheli V., Alonso E., Fleuret F.]\\n  year: 2023\\n  venue: ICLR\\n  category: direct-competitor\\n  role: \\\"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\\\"\\n  relevance_score: 3\\n\\n- paper_id: robine2023twm\\n  title: \\\"Transformer-based World Models Are Happy With 100k Interactions\\\"\\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\\n  year: 2023\\n  venue: ICLR\\n  category: direct-competitor\\n  role: \\\"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\\\"\\n  relevance_score: 3\\n\\n- paper_id: chen2022transdreamer\\n  title: \\\"TransDreamer: Reinforcement Learning with Transformer World Models\\\"\\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\\n  year: 2022\\n  venue: \\\"arXiv:2202.09481\\\"\\n  category: direct-competitor\\n  role: \\\"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: 2024-2026 concurrent work on temporal abstraction in world models\\n# ============================================================\\n\\n- paper_id: gumbsch2024thick\\n  title: \\\"Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics\\\"\\n  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]\\n  year: 2024\\n  venue: ICLR\\n  category: direct-competitor\\n  role: \\\"THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination\\\"\\n  relevance_score: 5\\n\\n- paper_id: mattes2024hieros\\n  title: \\\"Hieros: Hierarchical Imagination on Structured State Space Sequence World Models\\\"\\n  authors: [Mattes P., Schlosser R., Herbrich R.]\\n  year: 2024\\n  venue: ICML\\n  category: direct-competitor\\n  role: \\\"Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify\\\"\\n  relevance_score: 5\\n\\n# ============================================================\\n# NEW: Seed-dependent instability & value overestimation in MBRL\\n# ============================================================\\n\\n- paper_id: henderson2018deep\\n  title: \\\"Deep Reinforcement Learning that Matters\\\"\\n  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]\\n  year: 2018\\n  venue: AAAI\\n  category: background\\n  role: \\\"Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config\\\"\\n  relevance_score: 4\\n\\n- paper_id: nikishin2022primacy\\n  title: \\\"The Primacy Bias in Deep Reinforcement Learning\\\"\\n  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]\\n  year: 2022\\n  venue: ICML\\n  category: background\\n  role: \\\"Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent\\\"\\n  relevance_score: 4\\n\\n- paper_id: qiao2023mind\\n  title: \\\"Mind the Model, Not the Agent: The Primacy Bias in Model-based RL\\\"\\n  authors: [Qiao Z., Lyu J., Li X.]\\n  year: 2023\\n  venue: \\\"arXiv:2310.15017 (ECAI 2024)\\\"\\n  category: evaluation\\n  role: \\\"Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't\\\"\\n  relevance_score: 5\\n\\n- paper_id: hussing2024dissecting\\n  title: \\\"Dissecting Deep RL with High Update Ratios: Combatting Value Divergence\\\"\\n  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]\\n  year: 2024\\n  venue: \\\"Reinforcement Learning Journal (RLC 2024)\\\"\\n  category: evaluation\\n  role: \\\"Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization\\\"\\n  relevance_score: 4\\n\\n- paper_id: barkley2024stealing\\n  title: \\\"Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning\\\"\\n  authors: [Barkley B., Fridovich-Keil D.]\\n  year: 2024\\n  venue: \\\"arXiv:2412.14312 (ICML 2025)\\\"\\n  category: evaluation\\n  role: \\\"Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix\\\"\\n  relevance_score: 3\\n\\n- paper_id: bjorck2022variance\\n  title: \\\"Is High Variance Unavoidable in RL? A Case Study in Continuous Control\\\"\\n  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]\\n  year: 2022\\n  venue: ICLR\\n  category: background\\n  role: \\\"Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Reward prediction quality → MBRL performance\\n# ============================================================\\n# Our key finding: removing dt_embedding causes reward_MAE to spike 75x\\n# (0.01 → 0.747), making performance seed-dependent. These papers\\n# establish that reward prediction quality is a known MBRL bottleneck.\\n\\n- paper_id: lee2024dreamsmooth\\n  title: \\\"DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing\\\"\\n  authors: [Lee V., Abbeel P., Lee Y.]\\n  year: 2024\\n  venue: ICLR\\n  category: background\\n  role: \\\"Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x\\\"\\n  relevance_score: 5\\n\\n- paper_id: ma2024harmonydream\\n  title: \\\"HarmonyDream: Task Harmonization Inside World Models\\\"\\n  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]\\n  year: 2024\\n  venue: ICML\\n  category: background\\n  role: \\\"Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion\\\"\\n  relevance_score: 5\\n\\n- paper_id: lambert2020objective\\n  title: \\\"Objective Mismatch in Model-based Reinforcement Learning\\\"\\n  authors: [Lambert N., Amos B., Yadan O., Calandra R.]\\n  year: 2020\\n  venue: \\\"L4DC (Proceedings of Machine Learning Research, vol. 120)\\\"\\n  category: background\\n  role: \\\"Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch\\\"\\n  relevance_score: 4\\n\\n# ============================================================\\n# NEW: Auxiliary tasks & representation coupling in world models\\n# ============================================================\\n# Our finding: reward prediction quality is tightly coupled to temporal\\n# conditioning (dt_embedding). Removing the embedding degrades the\\n# reward head while dynamics remain intact — suggesting the reward head\\n# acts as more than a passive predictor; it conditions the shared\\n# representation. Literature gap: no prior work studies this coupling\\n# specifically in Dreamer-family world models.\\n\\n- paper_id: jaderberg2017unreal\\n  title: \\\"Reinforcement Learning with Unsupervised Auxiliary Tasks\\\"\\n  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]\\n  year: 2017\\n  venue: ICLR\\n  category: background\\n  role: \\\"UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction\\\"\\n  relevance_score: 4\\n\\n- paper_id: lyle2021auxiliary\\n  title: \\\"On The Effect of Auxiliary Tasks on Representation Dynamics\\\"\\n  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]\\n  year: 2021\\n  venue: AISTATS\\n  category: background\\n  role: \\\"Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space\\\"\\n  relevance_score: 4\\n\\n# ============================================================\\n# NEW: DreamerV3 architecture improvements (2025-2026)\\n# ============================================================\\n\\n- paper_id: bredis2026nedreamer\\n  title: \\\"Next Embedding Prediction Makes World Models Stronger\\\"\\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\\n  year: 2026\\n  venue: \\\"arXiv:2603.02765\\\"\\n  category: direct-competitor\\n  role: \\\"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\\\"\\n  relevance_score: 3\\n\\n- paper_id: zhang2025dymodreamer\\n  title: \\\"DyMoDreamer: World Modeling with Dynamic Modulation\\\"\\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\\n  year: 2025\\n  venue: NeurIPS\\n  category: direct-competitor\\n  role: \\\"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Temporal abstraction methods\\n# ============================================================\\n\\n- paper_id: liu2025vanta\\n  title: \\\"Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning\\\"\\n  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]\\n  year: 2025\\n  venue: ICLR\\n  category: method-component\\n  role: \\\"VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Evaluation methodology\\n# ============================================================\\n\\n- paper_id: agarwal2021precipice\\n  title: \\\"Deep Reinforcement Learning at the Edge of the Statistical Precipice\\\"\\n  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]\\n  year: 2021\\n  venue: NeurIPS\\n  category: evaluation\\n  role: \\\"Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds\\\"\\n  relevance_score: 4\\n\", \"total_chars\": 23504, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "9d5267f8-a52f-438f-a885-9d43e86d2e3a",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml\\\", \\\"content\\\": \\\"# Literature Map — event-gated-adaptive-horizon\\\\n# Last updated: 2026-05-14\\\\n# Total: 43 papers (5 existing + 38 new)\\\\n\\\\n# ============================================================\\\\n# EXISTING CITATIONS (already in paper.tex)\\\\n# ============================================================\\\\n\\\\n- paper_id: sutton1999options\\\\n  title: \\\\\\\"Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning\\\\\\\"\\\\n  authors: [Sutton R.S., Precup D., Singh S.]\\\\n  year: 1999\\\\n  venue: \\\\\\\"Artificial Intelligence 112(1-2):181-211\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL\\\\\\\"\\\\n  relevance_score: 5\\\\n\\\\n- paper_id: hafner2020dreamerv1\\\\n  title: \\\\\\\"Dream to Control: Learning Behaviors by Latent Imagination\\\\\\\"\\\\n  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]\\\\n  year: 2020\\\\n  venue: ICLR\\\\n  category: background\\\\n  role: \\\\\\\"DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm\\\\\\\"\\\\n  relevance_score: 5\\\\n\\\\n- paper_id: hafner2023dreamerv3\\\\n  title: \\\\\\\"Mastering Diverse Domains through World Models\\\\\\\"\\\\n  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]\\\\n  year: 2023\\\\n  venue: \\\\\\\"arXiv:2301.04104 (Nature 2025)\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here\\\\\\\"\\\\n  relevance_score: 5\\\\n\\\\n- paper_id: sharma2017figar\\\\n  title: \\\\\\\"Fine Grained Action Repetition for Deep Reinforcement Learning\\\\\\\"\\\\n  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]\\\\n  year: 2017\\\\n  venue: \\\\\\\"ICLR Workshop\\\\\\\"\\\\n  category: method-component\\\\n  role: \\\\\\\"FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: janner2019mbpo\\\\n  title: \\\\\\\"When to Trust Your Model: Model-Based Policy Optimization\\\\\\\"\\\\n  authors: [Janner M., Fu J., Zhang M., Levine S.]\\\\n  year: 2019\\\\n  venue: NeurIPS\\\\n  category: background\\\\n  role: \\\\\\\"MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding\\\\\\\"\\\\n  relevance_score: 5\\\\n\\\\n# ============================================================\\\\n# NEW: Multi-step prediction error compounding\\\\n# ============================================================\\\\n\\\\n- paper_id: ke2019learning\\\\n  title: \\\\\\\"Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future\\\\\\\"\\\\n  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]\\\\n  year: 2019\\\\n  venue: ICLR\\\\n  category: background\\\\n  role: \\\\\\\"Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: asadi2019combating\\\\n  title: \\\\\\\"Combating the Compounding-Error Problem with a Multi-step Model\\\\\\\"\\\\n  authors: [Asadi K., Misra D., Kim S., Littman M.L.]\\\\n  year: 2019\\\\n  venue: \\\\\\\"arXiv:1905.13320\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: venkatraman2015improving\\\\n  title: \\\\\\\"Improving Multi-Step Prediction of Learned Time Series Models\\\\\\\"\\\\n  authors: [Venkatraman A., Hebert M., Bagnell J.A.]\\\\n  year: 2015\\\\n  venue: AAAI\\\\n  category: background\\\\n  role: \\\\\\\"Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n- paper_id: lambert2022investigating\\\\n  title: \\\\\\\"Investigating Compounding Prediction Errors in Learned Dynamics Models\\\\\\\"\\\\n  authors: [Lambert N., Pister K.S.J., Calandra R.]\\\\n  year: 2022\\\\n  venue: \\\\\\\"arXiv:2203.09637\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n# ============================================================\\\\n# NEW: Model-predictive control with learned dynamics\\\\n# ============================================================\\\\n\\\\n- paper_id: chua2018pets\\\\n  title: \\\\\\\"Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models\\\\\\\"\\\\n  authors: [Chua K., Calandra R., McAllister R., Levine S.]\\\\n  year: 2018\\\\n  venue: NeurIPS\\\\n  category: background\\\\n  role: \\\\\\\"PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n- paper_id: nagabandi2018neural\\\\n  title: \\\\\\\"Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning\\\\\\\"\\\\n  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]\\\\n  year: 2018\\\\n  venue: ICRA\\\\n  category: background\\\\n  role: \\\\\\\"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n# ============================================================\\\\n# NEW: Value overestimation mitigation\\\\n# ============================================================\\\\n\\\\n- paper_id: thrun1993issues\\\\n  title: \\\\\\\"Issues in Using Function Approximation for Reinforcement Learning\\\\\\\"\\\\n  authors: [Thrun S., Schwartz A.]\\\\n  year: 1993\\\\n  venue: \\\\\\\"Connectionist Models Summer School\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: vanhasselt2016double\\\\n  title: \\\\\\\"Deep Reinforcement Learning with Double Q-Learning\\\\\\\"\\\\n  authors: [van Hasselt H., Guez A., Silver D.]\\\\n  year: 2016\\\\n  venue: AAAI\\\\n  category: background\\\\n  role: \\\\\\\"Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: fujimoto2018td3\\\\n  title: \\\\\\\"Addressing Function Approximation Error in Actor-Critic Methods\\\\\\\"\\\\n  authors: [Fujimoto S., van Hoof H., Meger D.]\\\\n  year: 2018\\\\n  venue: ICML\\\\n  category: method-component\\\\n  role: \\\\\\\"TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: haarnoja2018sac\\\\n  title: \\\\\\\"Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor\\\\\\\"\\\\n  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]\\\\n  year: 2018\\\\n  venue: ICML\\\\n  category: method-component\\\\n  role: \\\\\\\"SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n- paper_id: lee2021sunrise\\\\n  title: \\\\\\\"SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning\\\\\\\"\\\\n  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]\\\\n  year: 2021\\\\n  venue: ICML\\\\n  category: method-component\\\\n  role: \\\\\\\"Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n# ============================================================\\\\n# NEW: Delusional bias\\\\n# ============================================================\\\\n\\\\n- paper_id: lu2018nondelusional\\\\n  title: \\\\\\\"Non-delusional Q-learning and Value-Iteration\\\\\\\"\\\\n  authors: [Lu T., Schuurmans D., Boutilier C.]\\\\n  year: 2018\\\\n  venue: NeurIPS\\\\n  category: background\\\\n  role: \\\\\\\"Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision\\\\\\\"\\\\n  relevance_score: 5\\\\n\\\\n# ============================================================\\\\n# NEW: Hierarchical RL with learned models\\\\n# ============================================================\\\\n\\\\n- paper_id: hafner2022director\\\\n  title: \\\\\\\"Deep Hierarchical Planning from Pixels\\\\\\\"\\\\n  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]\\\\n  year: 2022\\\\n  venue: NeurIPS\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: nachum2018hiro\\\\n  title: \\\\\\\"Data-Efficient Hierarchical Reinforcement Learning\\\\\\\"\\\\n  authors: [Nachum O., Gu S., Lee H., Levine S.]\\\\n  year: 2018\\\\n  venue: NeurIPS\\\\n  category: background\\\\n  role: \\\\\\\"HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n# ============================================================\\\\n# NEW: Action repeat / frame skip\\\\n# ============================================================\\\\n\\\\n- paper_id: braylan2015frame\\\\n  title: \\\\\\\"Frame Skip Is a Powerful Parameter for Learning to Play Atari\\\\\\\"\\\\n  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]\\\\n  year: 2015\\\\n  venue: \\\\\\\"AAAI Workshop on Learning for General Competency in Video Games\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n- paper_id: lakshminarayanan2017dynamic\\\\n  title: \\\\\\\"Dynamic Action Repetition for Deep Reinforcement Learning\\\\\\\"\\\\n  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]\\\\n  year: 2017\\\\n  venue: AAAI\\\\n  category: method-component\\\\n  role: \\\\\\\"Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: biedenkapp2021temporl\\\\n  title: \\\\\\\"TempoRL: Learning When to Act\\\\\\\"\\\\n  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]\\\\n  year: 2021\\\\n  venue: ICML\\\\n  category: method-component\\\\n  role: \\\\\\\"Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n# ============================================================\\\\n# NEW: DreamerV2\\\\n# ============================================================\\\\n\\\\n- paper_id: hafner2021dreamerv2\\\\n  title: \\\\\\\"Mastering Atari with Discrete World Models\\\\\\\"\\\\n  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]\\\\n  year: 2021\\\\n  venue: ICLR\\\\n  category: background\\\\n  role: \\\\\\\"DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system\\\\\\\"\\\\n  relevance_score: 5\\\\n\\\\n# ============================================================\\\\n# NEW: Alternative world model architectures\\\\n# ============================================================\\\\n\\\\n- paper_id: micheli2023iris\\\\n  title: \\\\\\\"Transformers are Sample-Efficient World Models\\\\\\\"\\\\n  authors: [Micheli V., Alonso E., Fleuret F.]\\\\n  year: 2023\\\\n  venue: ICLR\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n- paper_id: robine2023twm\\\\n  title: \\\\\\\"Transformer-based World Models Are Happy With 100k Interactions\\\\\\\"\\\\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\\\\n  year: 2023\\\\n  venue: ICLR\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n- paper_id: chen2022transdreamer\\\\n  title: \\\\\\\"TransDreamer: Reinforcement Learning with Transformer World Models\\\\\\\"\\\\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\\\\n  year: 2022\\\\n  venue: \\\\\\\"arXiv:2202.09481\\\\\\\"\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n# ============================================================\\\\n# NEW: 2024-2026 concurrent work on temporal abstraction in world models\\\\n# ============================================================\\\\n\\\\n- paper_id: gumbsch2024thick\\\\n  title: \\\\\\\"Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics\\\\\\\"\\\\n  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]\\\\n  year: 2024\\\\n  venue: ICLR\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination\\\\\\\"\\\\n  relevance_score: 5\\\\n\\\\n- paper_id: mattes2024hieros\\\\n  title: \\\\\\\"Hieros: Hierarchical Imagination on Structured State Space Sequence World Models\\\\\\\"\\\\n  authors: [Mattes P., Schlosser R., Herbrich R.]\\\\n  year: 2024\\\\n  venue: ICML\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify\\\\\\\"\\\\n  relevance_score: 5\\\\n\\\\n# ============================================================\\\\n# NEW: Seed-dependent instability & value overestimation in MBRL\\\\n# ============================================================\\\\n\\\\n- paper_id: henderson2018deep\\\\n  title: \\\\\\\"Deep Reinforcement Learning that Matters\\\\\\\"\\\\n  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]\\\\n  year: 2018\\\\n  venue: AAAI\\\\n  category: background\\\\n  role: \\\\\\\"Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: nikishin2022primacy\\\\n  title: \\\\\\\"The Primacy Bias in Deep Reinforcement Learning\\\\\\\"\\\\n  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]\\\\n  year: 2022\\\\n  venue: ICML\\\\n  category: background\\\\n  role: \\\\\\\"Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: qiao2023mind\\\\n  title: \\\\\\\"Mind the Model, Not the Agent: The Primacy Bias in Model-based RL\\\\\\\"\\\\n  authors: [Qiao Z., Lyu J., Li X.]\\\\n  year: 2023\\\\n  venue: \\\\\\\"arXiv:2310.15017 (ECAI 2024)\\\\\\\"\\\\n  category: evaluation\\\\n  role: \\\\\\\"Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't\\\\\\\"\\\\n  relevance_score: 5\\\\n\\\\n- paper_id: hussing2024dissecting\\\\n  title: \\\\\\\"Dissecting Deep RL with High Update Ratios: Combatting Value Divergence\\\\\\\"\\\\n  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]\\\\n  year: 2024\\\\n  venue: \\\\\\\"Reinforcement Learning Journal (RLC 2024)\\\\\\\"\\\\n  category: evaluation\\\\n  role: \\\\\\\"Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: barkley2024stealing\\\\n  title: \\\\\\\"Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning\\\\\\\"\\\\n  authors: [Barkley B., Fridovich-Keil D.]\\\\n  year: 2024\\\\n  venue: \\\\\\\"arXiv:2412.14312 (ICML 2025)\\\\\\\"\\\\n  category: evaluation\\\\n  role: \\\\\\\"Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n- paper_id: bjorck2022variance\\\\n  title: \\\\\\\"Is High Variance Unavoidable in RL? A Case Study in Continuous Control\\\\\\\"\\\\n  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]\\\\n  year: 2022\\\\n  venue: ICLR\\\\n  category: background\\\\n  role: \\\\\\\"Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n# ============================================================\\\\n# NEW: Reward prediction quality → MBRL performance\\\\n# ============================================================\\\\n# Our key finding: removing dt_embedding causes reward_MAE to spike 75x\\\\n# (0.01 → 0.747), making performance seed-dependent. These papers\\\\n# establish that reward prediction quality is a known MBRL bottleneck.\\\\n\\\\n- paper_id: lee2024dreamsmooth\\\\n  title: \\\\\\\"DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing\\\\\\\"\\\\n  authors: [Lee V., Abbeel P., Lee Y.]\\\\n  year: 2024\\\\n  venue: ICLR\\\\n  category: background\\\\n  role: \\\\\\\"Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x\\\\\\\"\\\\n  relevance_score: 5\\\\n\\\\n- paper_id: ma2024harmonydream\\\\n  title: \\\\\\\"HarmonyDream: Task Harmonization Inside World Models\\\\\\\"\\\\n  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]\\\\n  year: 2024\\\\n  venue: ICML\\\\n  category: background\\\\n  role: \\\\\\\"Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion\\\\\\\"\\\\n  relevance_score: 5\\\\n\\\\n- paper_id: lambert2020objective\\\\n  title: \\\\\\\"Objective Mismatch in Model-based Reinforcement Learning\\\\\\\"\\\\n  authors: [Lambert N., Amos B., Yadan O., Calandra R.]\\\\n  year: 2020\\\\n  venue: \\\\\\\"L4DC (Proceedings of Machine Learning Research, vol. 120)\\\\\\\"\\\\n  category: background\\\\n  role: \\\\\\\"Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n# ============================================================\\\\n# NEW: Auxiliary tasks & representation coupling in world models\\\\n# ============================================================\\\\n# Our finding: reward prediction quality is tightly coupled to temporal\\\\n# conditioning (dt_embedding). Removing the embedding degrades the\\\\n# reward head while dynamics remain intact — suggesting the reward head\\\\n# acts as more than a passive predictor; it conditions the shared\\\\n# representation. Literature gap: no prior work studies this coupling\\\\n# specifically in Dreamer-family world models.\\\\n\\\\n- paper_id: jaderberg2017unreal\\\\n  title: \\\\\\\"Reinforcement Learning with Unsupervised Auxiliary Tasks\\\\\\\"\\\\n  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]\\\\n  year: 2017\\\\n  venue: ICLR\\\\n  category: background\\\\n  role: \\\\\\\"UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n- paper_id: lyle2021auxiliary\\\\n  title: \\\\\\\"On The Effect of Auxiliary Tasks on Representation Dynamics\\\\\\\"\\\\n  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]\\\\n  year: 2021\\\\n  venue: AISTATS\\\\n  category: background\\\\n  role: \\\\\\\"Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\\n# ============================================================\\\\n# NEW: DreamerV3 architecture improvements (2025-2026)\\\\n# ============================================================\\\\n\\\\n- paper_id: bredis2026nedreamer\\\\n  title: \\\\\\\"Next Embedding Prediction Makes World Models Stronger\\\\\\\"\\\\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\\\\n  year: 2026\\\\n  venue: \\\\\\\"arXiv:2603.02765\\\\\\\"\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n- paper_id: zhang2025dymodreamer\\\\n  title: \\\\\\\"DyMoDreamer: World Modeling with Dynamic Modulation\\\\\\\"\\\\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\\\\n  year: 2025\\\\n  venue: NeurIPS\\\\n  category: direct-competitor\\\\n  role: \\\\\\\"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n# ============================================================\\\\n# NEW: Temporal abstraction methods\\\\n# ============================================================\\\\n\\\\n- paper_id: liu2025vanta\\\\n  title: \\\\\\\"Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning\\\\\\\"\\\\n  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]\\\\n  year: 2025\\\\n  venue: ICLR\\\\n  category: method-component\\\\n  role: \\\\\\\"VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps\\\\\\\"\\\\n  relevance_score: 3\\\\n\\\\n# ============================================================\\\\n# NEW: Evaluation methodology\\\\n# ============================================================\\\\n\\\\n- paper_id: agarwal2021precipice\\\\n  title: \\\\\\\"Deep Reinforcement Learning at the Edge of the Statistical Precipice\\\\\\\"\\\\n  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]\\\\n  year: 2021\\\\n  venue: NeurIPS\\\\n  category: evaluation\\\\n  role: \\\\\\\"Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds\\\\\\\"\\\\n  relevance_score: 4\\\\n\\\", \\\"total_chars\\\": 23504, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml\", \"content\": \"# Literature Map — event-gated-adaptive-horizon\\n# Last updated: 2026-05-14\\n# Total: 43 papers (5 existing + 38 new)\\n\\n# ============================================================\\n# EXISTING CITATIONS (already in paper.tex)\\n# ============================================================\\n\\n- paper_id: sutton1999options\\n  title: \\\"Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning\\\"\\n  authors: [Sutton R.S., Precup D., Singh S.]\\n  year: 1999\\n  venue: \\\"Artificial Intelligence 112(1-2):181-211\\\"\\n  category: background\\n  role: \\\"Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL\\\"\\n  relevance_score: 5\\n\\n- paper_id: hafner2020dreamerv1\\n  title: \\\"Dream to Control: Learning Behaviors by Latent Imagination\\\"\\n  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]\\n  year: 2020\\n  venue: ICLR\\n  category: background\\n  role: \\\"DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm\\\"\\n  relevance_score: 5\\n\\n- paper_id: hafner2023dreamerv3\\n  title: \\\"Mastering Diverse Domains through World Models\\\"\\n  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]\\n  year: 2023\\n  venue: \\\"arXiv:2301.04104 (Nature 2025)\\\"\\n  category: background\\n  role: \\\"DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here\\\"\\n  relevance_score: 5\\n\\n- paper_id: sharma2017figar\\n  title: \\\"Fine Grained Action Repetition for Deep Reinforcement Learning\\\"\\n  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]\\n  year: 2017\\n  venue: \\\"ICLR Workshop\\\"\\n  category: method-component\\n  role: \\\"FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL\\\"\\n  relevance_score: 4\\n\\n- paper_id: janner2019mbpo\\n  title: \\\"When to Trust Your Model: Model-Based Policy Optimization\\\"\\n  authors: [Janner M., Fu J., Zhang M., Levine S.]\\n  year: 2019\\n  venue: NeurIPS\\n  category: background\\n  role: \\\"MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding\\\"\\n  relevance_score: 5\\n\\n# ============================================================\\n# NEW: Multi-step prediction error compounding\\n# ============================================================\\n\\n- paper_id: ke2019learning\\n  title: \\\"Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future\\\"\\n  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]\\n  year: 2019\\n  venue: ICLR\\n  category: background\\n  role: \\\"Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1\\\"\\n  relevance_score: 4\\n\\n- paper_id: asadi2019combating\\n  title: \\\"Combating the Compounding-Error Problem with a Multi-step Model\\\"\\n  authors: [Asadi K., Misra D., Kim S., Littman M.L.]\\n  year: 2019\\n  venue: \\\"arXiv:1905.13320\\\"\\n  category: background\\n  role: \\\"Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error\\\"\\n  relevance_score: 4\\n\\n- paper_id: venkatraman2015improving\\n  title: \\\"Improving Multi-Step Prediction of Learned Time Series Models\\\"\\n  authors: [Venkatraman A., Hebert M., Bagnell J.A.]\\n  year: 2015\\n  venue: AAAI\\n  category: background\\n  role: \\\"Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error\\\"\\n  relevance_score: 3\\n\\n- paper_id: lambert2022investigating\\n  title: \\\"Investigating Compounding Prediction Errors in Learned Dynamics Models\\\"\\n  authors: [Lambert N., Pister K.S.J., Calandra R.]\\n  year: 2022\\n  venue: \\\"arXiv:2203.09637\\\"\\n  category: background\\n  role: \\\"Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Model-predictive control with learned dynamics\\n# ============================================================\\n\\n- paper_id: chua2018pets\\n  title: \\\"Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models\\\"\\n  authors: [Chua K., Calandra R., McAllister R., Levine S.]\\n  year: 2018\\n  venue: NeurIPS\\n  category: background\\n  role: \\\"PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach\\\"\\n  relevance_score: 3\\n\\n- paper_id: nagabandi2018neural\\n  title: \\\"Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning\\\"\\n  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]\\n  year: 2018\\n  venue: ICRA\\n  category: background\\n  role: \\\"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Value overestimation mitigation\\n# ============================================================\\n\\n- paper_id: thrun1993issues\\n  title: \\\"Issues in Using Function Approximation for Reinforcement Learning\\\"\\n  authors: [Thrun S., Schwartz A.]\\n  year: 1993\\n  venue: \\\"Connectionist Models Summer School\\\"\\n  category: background\\n  role: \\\"First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning\\\"\\n  relevance_score: 4\\n\\n- paper_id: vanhasselt2016double\\n  title: \\\"Deep Reinforcement Learning with Double Q-Learning\\\"\\n  authors: [van Hasselt H., Guez A., Silver D.]\\n  year: 2016\\n  venue: AAAI\\n  category: background\\n  role: \\\"Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL\\\"\\n  relevance_score: 4\\n\\n- paper_id: fujimoto2018td3\\n  title: \\\"Addressing Function Approximation Error in Actor-Critic Methods\\\"\\n  authors: [Fujimoto S., van Hoof H., Meger D.]\\n  year: 2018\\n  venue: ICML\\n  category: method-component\\n  role: \\\"TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify\\\"\\n  relevance_score: 4\\n\\n- paper_id: haarnoja2018sac\\n  title: \\\"Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor\\\"\\n  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]\\n  year: 2018\\n  venue: ICML\\n  category: method-component\\n  role: \\\"SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values\\\"\\n  relevance_score: 3\\n\\n- paper_id: lee2021sunrise\\n  title: \\\"SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning\\\"\\n  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]\\n  year: 2021\\n  venue: ICML\\n  category: method-component\\n  role: \\\"Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Delusional bias\\n# ============================================================\\n\\n- paper_id: lu2018nondelusional\\n  title: \\\"Non-delusional Q-learning and Value-Iteration\\\"\\n  authors: [Lu T., Schuurmans D., Boutilier C.]\\n  year: 2018\\n  venue: NeurIPS\\n  category: background\\n  role: \\\"Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision\\\"\\n  relevance_score: 5\\n\\n# ============================================================\\n# NEW: Hierarchical RL with learned models\\n# ============================================================\\n\\n- paper_id: hafner2022director\\n  title: \\\"Deep Hierarchical Planning from Pixels\\\"\\n  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]\\n  year: 2022\\n  venue: NeurIPS\\n  category: direct-competitor\\n  role: \\\"Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt\\\"\\n  relevance_score: 4\\n\\n- paper_id: nachum2018hiro\\n  title: \\\"Data-Efficient Hierarchical Reinforcement Learning\\\"\\n  authors: [Nachum O., Gu S., Lee H., Levine S.]\\n  year: 2018\\n  venue: NeurIPS\\n  category: background\\n  role: \\\"HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Action repeat / frame skip\\n# ============================================================\\n\\n- paper_id: braylan2015frame\\n  title: \\\"Frame Skip Is a Powerful Parameter for Learning to Play Atari\\\"\\n  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]\\n  year: 2015\\n  venue: \\\"AAAI Workshop on Learning for General Competency in Video Games\\\"\\n  category: background\\n  role: \\\"Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice\\\"\\n  relevance_score: 3\\n\\n- paper_id: lakshminarayanan2017dynamic\\n  title: \\\"Dynamic Action Repetition for Deep Reinforcement Learning\\\"\\n  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]\\n  year: 2017\\n  venue: AAAI\\n  category: method-component\\n  role: \\\"Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach\\\"\\n  relevance_score: 4\\n\\n- paper_id: biedenkapp2021temporl\\n  title: \\\"TempoRL: Learning When to Act\\\"\\n  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]\\n  year: 2021\\n  venue: ICML\\n  category: method-component\\n  role: \\\"Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify\\\"\\n  relevance_score: 4\\n\\n# ============================================================\\n# NEW: DreamerV2\\n# ============================================================\\n\\n- paper_id: hafner2021dreamerv2\\n  title: \\\"Mastering Atari with Discrete World Models\\\"\\n  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]\\n  year: 2021\\n  venue: ICLR\\n  category: background\\n  role: \\\"DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system\\\"\\n  relevance_score: 5\\n\\n# ============================================================\\n# NEW: Alternative world model architectures\\n# ============================================================\\n\\n- paper_id: micheli2023iris\\n  title: \\\"Transformers are Sample-Efficient World Models\\\"\\n  authors: [Micheli V., Alonso E., Fleuret F.]\\n  year: 2023\\n  venue: ICLR\\n  category: direct-competitor\\n  role: \\\"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\\\"\\n  relevance_score: 3\\n\\n- paper_id: robine2023twm\\n  title: \\\"Transformer-based World Models Are Happy With 100k Interactions\\\"\\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\\n  year: 2023\\n  venue: ICLR\\n  category: direct-competitor\\n  role: \\\"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\\\"\\n  relevance_score: 3\\n\\n- paper_id: chen2022transdreamer\\n  title: \\\"TransDreamer: Reinforcement Learning with Transformer World Models\\\"\\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\\n  year: 2022\\n  venue: \\\"arXiv:2202.09481\\\"\\n  category: direct-competitor\\n  role: \\\"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: 2024-2026 concurrent work on temporal abstraction in world models\\n# ============================================================\\n\\n- paper_id: gumbsch2024thick\\n  title: \\\"Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics\\\"\\n  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]\\n  year: 2024\\n  venue: ICLR\\n  category: direct-competitor\\n  role: \\\"THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination\\\"\\n  relevance_score: 5\\n\\n- paper_id: mattes2024hieros\\n  title: \\\"Hieros: Hierarchical Imagination on Structured State Space Sequence World Models\\\"\\n  authors: [Mattes P., Schlosser R., Herbrich R.]\\n  year: 2024\\n  venue: ICML\\n  category: direct-competitor\\n  role: \\\"Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify\\\"\\n  relevance_score: 5\\n\\n# ============================================================\\n# NEW: Seed-dependent instability & value overestimation in MBRL\\n# ============================================================\\n\\n- paper_id: henderson2018deep\\n  title: \\\"Deep Reinforcement Learning that Matters\\\"\\n  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]\\n  year: 2018\\n  venue: AAAI\\n  category: background\\n  role: \\\"Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config\\\"\\n  relevance_score: 4\\n\\n- paper_id: nikishin2022primacy\\n  title: \\\"The Primacy Bias in Deep Reinforcement Learning\\\"\\n  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]\\n  year: 2022\\n  venue: ICML\\n  category: background\\n  role: \\\"Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent\\\"\\n  relevance_score: 4\\n\\n- paper_id: qiao2023mind\\n  title: \\\"Mind the Model, Not the Agent: The Primacy Bias in Model-based RL\\\"\\n  authors: [Qiao Z., Lyu J., Li X.]\\n  year: 2023\\n  venue: \\\"arXiv:2310.15017 (ECAI 2024)\\\"\\n  category: evaluation\\n  role: \\\"Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't\\\"\\n  relevance_score: 5\\n\\n- paper_id: hussing2024dissecting\\n  title: \\\"Dissecting Deep RL with High Update Ratios: Combatting Value Divergence\\\"\\n  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]\\n  year: 2024\\n  venue: \\\"Reinforcement Learning Journal (RLC 2024)\\\"\\n  category: evaluation\\n  role: \\\"Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization\\\"\\n  relevance_score: 4\\n\\n- paper_id: barkley2024stealing\\n  title: \\\"Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning\\\"\\n  authors: [Barkley B., Fridovich-Keil D.]\\n  year: 2024\\n  venue: \\\"arXiv:2412.14312 (ICML 2025)\\\"\\n  category: evaluation\\n  role: \\\"Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix\\\"\\n  relevance_score: 3\\n\\n- paper_id: bjorck2022variance\\n  title: \\\"Is High Variance Unavoidable in RL? A Case Study in Continuous Control\\\"\\n  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]\\n  year: 2022\\n  venue: ICLR\\n  category: background\\n  role: \\\"Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Reward prediction quality → MBRL performance\\n# ============================================================\\n# Our key finding: removing dt_embedding causes reward_MAE to spike 75x\\n# (0.01 → 0.747), making performance seed-dependent. These papers\\n# establish that reward prediction quality is a known MBRL bottleneck.\\n\\n- paper_id: lee2024dreamsmooth\\n  title: \\\"DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing\\\"\\n  authors: [Lee V., Abbeel P., Lee Y.]\\n  year: 2024\\n  venue: ICLR\\n  category: background\\n  role: \\\"Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x\\\"\\n  relevance_score: 5\\n\\n- paper_id: ma2024harmonydream\\n  title: \\\"HarmonyDream: Task Harmonization Inside World Models\\\"\\n  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]\\n  year: 2024\\n  venue: ICML\\n  category: background\\n  role: \\\"Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion\\\"\\n  relevance_score: 5\\n\\n- paper_id: lambert2020objective\\n  title: \\\"Objective Mismatch in Model-based Reinforcement Learning\\\"\\n  authors: [Lambert N., Amos B., Yadan O., Calandra R.]\\n  year: 2020\\n  venue: \\\"L4DC (Proceedings of Machine Learning Research, vol. 120)\\\"\\n  category: background\\n  role: \\\"Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch\\\"\\n  relevance_score: 4\\n\\n# ============================================================\\n# NEW: Auxiliary tasks & representation coupling in world models\\n# ============================================================\\n# Our finding: reward prediction quality is tightly coupled to temporal\\n# conditioning (dt_embedding). Removing the embedding degrades the\\n# reward head while dynamics remain intact — suggesting the reward head\\n# acts as more than a passive predictor; it conditions the shared\\n# representation. Literature gap: no prior work studies this coupling\\n# specifically in Dreamer-family world models.\\n\\n- paper_id: jaderberg2017unreal\\n  title: \\\"Reinforcement Learning with Unsupervised Auxiliary Tasks\\\"\\n  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]\\n  year: 2017\\n  venue: ICLR\\n  category: background\\n  role: \\\"UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction\\\"\\n  relevance_score: 4\\n\\n- paper_id: lyle2021auxiliary\\n  title: \\\"On The Effect of Auxiliary Tasks on Representation Dynamics\\\"\\n  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]\\n  year: 2021\\n  venue: AISTATS\\n  category: background\\n  role: \\\"Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space\\\"\\n  relevance_score: 4\\n\\n# ============================================================\\n# NEW: DreamerV3 architecture improvements (2025-2026)\\n# ============================================================\\n\\n- paper_id: bredis2026nedreamer\\n  title: \\\"Next Embedding Prediction Makes World Models Stronger\\\"\\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\\n  year: 2026\\n  venue: \\\"arXiv:2603.02765\\\"\\n  category: direct-competitor\\n  role: \\\"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\\\"\\n  relevance_score: 3\\n\\n- paper_id: zhang2025dymodreamer\\n  title: \\\"DyMoDreamer: World Modeling with Dynamic Modulation\\\"\\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\\n  year: 2025\\n  venue: NeurIPS\\n  category: direct-competitor\\n  role: \\\"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Temporal abstraction methods\\n# ============================================================\\n\\n- paper_id: liu2025vanta\\n  title: \\\"Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning\\\"\\n  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]\\n  year: 2025\\n  venue: ICLR\\n  category: method-component\\n  role: \\\"VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps\\\"\\n  relevance_score: 3\\n\\n# ============================================================\\n# NEW: Evaluation methodology\\n# ============================================================\\n\\n- paper_id: agarwal2021precipice\\n  title: \\\"Deep Reinforcement Learning at the Edge of the Statistical Precipice\\\"\\n  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]\\n  year: 2021\\n  venue: NeurIPS\\n  category: evaluation\\n  role: \\\"Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds\\\"\\n  relevance_score: 4\\n\", \"total_chars\": 23504, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 10_

<details open><summary>🔧 Tool call — WebSearch · `toolu_012VAJLyv6o9pJBTNpH5VxDr`</summary>

```json
{
  "query": "TD-MPC2 Hansen ICLR 2024 arXiv paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "51d90589-a910-4168-b83c-aacf9919105b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Hj9jmguPnxyr2PTuC1KNzn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1225,
      "cache_read_input_tokens": 23277,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1225
      },
      "output_tokens": 43,
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

_source line 11_

<details open><summary>🔧 Tool call — WebSearch · `toolu_015NttQXXfcCdLY65q983HRB`</summary>

```json
{
  "query": "MOPO Yu et al NeurIPS 2020 arXiv model-based offline policy optimization"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "07ddf308-d90d-4cca-94b8-22a3ff863f63",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Hj9jmguPnxyr2PTuC1KNzn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1225,
      "cache_read_input_tokens": 23277,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1225
      },
      "output_tokens": 43,
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

_source line 12 · 2026-05-14T14:56:45.138Z_

<details><summary>↩ Tool result · `toolu_012VAJLyv6o9pJBTNpH5VxDr`</summary>

```text
Web search results for query: "TD-MPC2 Hansen ICLR 2024 arXiv paper"

Links: [{"title":"[2310.16828] TD-MPC2: Scalable, Robust World Models for Continuous Control","url":"https://arxiv.org/abs/2310.16828"},{"title":"Published as a conference paper at ICLR 2024 TD-MPC2:","url":"https://arxiv.org/pdf/2310.16828"},{"title":"TD-MPC2","url":"https://www.tdmpc2.com/"},{"title":"Published as a conference paper at ICLR 2024","url":"https://openreview.net/pdf/d7962b8e764953c9c4db96aa85307e9e9b689881.pdf"},{"title":"TD-MPC2: Scalable, Robust World Models for Continuous Control TD-MPC2","url":"https://iclr.cc/media/iclr-2024/Slides/18722.pdf"},{"title":"[LR] TD-MPC2 | Notes","url":"https://howardhsuuu.github.io/posts/lr/tdmpc2/"},{"title":"[PDF] TD-MPC2: Scalable, Robust World Models for Continuous Control | Semantic Scholar","url":"https://www.semanticscholar.org/paper/TD-MPC2:-Scalable,-Robust-World-Models-for-Control-Hansen-Su/8eeccf1033fd759c868b29ccb6aa70f5ffd1887c"},{"title":"TD-MPC2: Scalable, Robust World Models for Continuous Control","url":"https://proceedings.iclr.cc/paper_files/paper/2024/hash/cf73d57b6dcda32b293df7c2d5341f49-Abstract-Conference.html"},{"title":"TD-MPC2: Scalable, Robust World Models for Continuous Control","url":"https://arxiv.org/html/2310.16828v2"},{"title":"TD-MPC2: Scalable, Robust World Models for Continuous Control | OpenReview","url":"https://openreview.net/forum?id=Oxh5CstDJU"}]

I found the paper you're looking for. Here's what I found:

## TD-MPC2: Scalable, Robust World Models for Continuous Control

The paper was published as a conference paper at ICLR 2024 by Nicklas Hansen, Hao Su, and Xiaolong Wang from the University of California San Diego. The arXiv ID is **2310.16828**.

### Key Details:

**Paper Purpose:** TD-MPC2 presents a series of improvements upon the TD-MPC algorithm.

**Main Results:** TD-MPC2 improves significantly over baselines across 104 online RL tasks spanning 4 diverse task domains, achieving consistently strong results with a single set of hyperparameters. Additionally, the authors successfully trained a single 317M parameter agent to perform 80 tasks across multiple task domains, embodiments, and action spaces.

**Algorithm Overview:** TD-MPC2 is a model-based RL algorithm designed for learning generalist world models on large uncurated datasets composed of multiple task domains, embodiments, and action spaces, with data sourced from behavior policies that cover a wide range of skill levels, and without the need for hyperparameter-tuning.

### Resources:
- **arXiv**: https://arxiv.org/abs/2310.16828
- **Official Website**: https://www.tdmpc2.com/


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "c3af631d-bd57-4677-9936-e20116ff0ff0",
  "tool_use_result": {
    "query": "TD-MPC2 Hansen ICLR 2024 arXiv paper",
    "results": [
      {
        "tool_use_id": "srvtoolu_01Rwmq7f5s9bMY7sah7PTheY",
        "content": [
          {
            "title": "[2310.16828] TD-MPC2: Scalable, Robust World Models for Continuous Control",
            "url": "https://arxiv.org/abs/2310.16828"
          },
          {
            "title": "Published as a conference paper at ICLR 2024 TD-MPC2:",
            "url": "https://arxiv.org/pdf/2310.16828"
          },
          {
            "title": "TD-MPC2",
            "url": "https://www.tdmpc2.com/"
          },
          {
            "title": "Published as a conference paper at ICLR 2024",
            "url": "https://openreview.net/pdf/d7962b8e764953c9c4db96aa85307e9e9b689881.pdf"
          },
          {
            "title": "TD-MPC2: Scalable, Robust World Models for Continuous Control TD-MPC2",
            "url": "https://iclr.cc/media/iclr-2024/Slides/18722.pdf"
          },
          {
            "title": "[LR] TD-MPC2 | Notes",
            "url": "https://howardhsuuu.github.io/posts/lr/tdmpc2/"
          },
          {
            "title": "[PDF] TD-MPC2: Scalable, Robust World Models for Continuous Control | Semantic Scholar",
            "url": "https://www.semanticscholar.org/paper/TD-MPC2:-Scalable,-Robust-World-Models-for-Control-Hansen-Su/8eeccf1033fd759c868b29ccb6aa70f5ffd1887c"
          },
          {
            "title": "TD-MPC2: Scalable, Robust World Models for Continuous Control",
            "url": "https://proceedings.iclr.cc/paper_files/paper/2024/hash/cf73d57b6dcda32b293df7c2d5341f49-Abstract-Conference.html"
          },
          {
            "title": "TD-MPC2: Scalable, Robust World Models for Continuous Control",
            "url": "https://arxiv.org/html/2310.16828v2"
          },
          {
            "title": "TD-MPC2: Scalable, Robust World Models for Continuous Control | OpenReview",
            "url": "https://openreview.net/forum?id=Oxh5CstDJU"
          }
        ]
      },
      "I found the paper you're looking for. Here's what I found:\n\n## TD-MPC2: Scalable, Robust World Models for Continuous Control\n\nThe paper was published as a conference paper at ICLR 2024 by Nicklas Hansen, Hao Su, and Xiaolong Wang from the University of California San Diego. The arXiv ID is **2310.16828**.\n\n### Key Details:\n\n**Paper Purpose:** TD-MPC2 presents a series of improvements upon the TD-MPC algorithm.\n\n**Main Results:** TD-MPC2 improves significantly over baselines across 104 online RL tasks spanning 4 diverse task domains, achieving consistently strong results with a single set of hyperparameters. Additionally, the authors successfully trained a single 317M parameter agent to perform 80 tasks across multiple task domains, embodiments, and action spaces.\n\n**Algorithm Overview:** TD-MPC2 is a model-based RL algorithm designed for learning generalist world models on large uncurated datasets composed of multiple task domains, embodiments, and action spaces, with data sourced from behavior policies that cover a wide range of skill levels, and without the need for hyperparameter-tuning.\n\n### Resources:\n- **arXiv**: https://arxiv.org/abs/2310.16828\n- **Official Website**: https://www.tdmpc2.com/"
    ],
    "durationSeconds": 6.081032125000002
  }
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-14T14:56:46.510Z_

<details><summary>↩ Tool result · `toolu_015NttQXXfcCdLY65q983HRB`</summary>

```text
Web search results for query: "MOPO Yu et al NeurIPS 2020 arXiv model-based offline policy optimization"

Links: [{"title":"MOPO: Model-based Offline Policy Optimization","url":"https://arxiv.org/pdf/2005.13239"},{"title":"MOPO: Model-based Offline Policy Optimization","url":"https://proceedings.neurips.cc/paper_files/paper/2020/hash/a322852ce0df73e204b7e67cbbef0d0a-Abstract.html"},{"title":"MOPO: Model-based Offline Policy Optimization","url":"https://proceedings.nips.cc/paper/2020/file/a322852ce0df73e204b7e67cbbef0d0a-Paper.pdf"},{"title":"MOPO: Model-based Offline Policy Optimization - ADS","url":"https://ui.adsabs.harvard.edu/abs/2020arXiv200513239Y/abstract"},{"title":"Offline Model-Based Optimization via Policy-Guided Gradient Search","url":"https://arxiv.org/html/2405.05349v1"},{"title":"Review for NeurIPS paper: MOPO: Model-based Offline Policy Optimization","url":"https://proceedings.neurips.cc/paper/2020/file/a322852ce0df73e204b7e67cbbef0d0a-Review.html"},{"title":"Model-based Policy Optimization with Unsupervised Model Adaptation","url":"https://proceedings.neurips.cc/paper/2020/file/1dc3a89d0d440ba31729b0ba74b93a33-Paper.pdf"},{"title":"[2005.13239] MOPO: Model-based Offline Policy Optimization","url":"https://arxiv.org/abs/2005.13239"},{"title":"MOPO: model-based offline policy optimization","url":"https://dl.acm.org/doi/10.5555/3495724.3496909"},{"title":"MOPO: Model-based Offline Policy Optimization - Jianan Chen","url":"https://gjiananchen.github.io/publications/MOPO"}]

I found comprehensive information about the MOPO paper. Here's what the search reveals:

MOPO was presented at the 34th Conference on Neural Information Processing Systems (NeurIPS 2020) in Vancouver, Canada.

**Key Details:**

The paper was authored by Tianhe Yu, Garrett Thomas, Lantao Yu, Stefano Ermon, James Zou, Sergey Levine, Chelsea Finn, and Tengyu Ma.

**Main Contribution:**

The primary contribution is an offline model-based RL algorithm that optimizes a policy in an uncertainty-penalized MDP, where the reward function is penalized by an estimate of the model's error. Under this new MDP, the authors theoretically show that they maximize a lower bound of the return in the true MDP, and find the optimal trade-off between the return and the risk.

**Algorithm:**

The practical method estimates model error using the predicted variance of a learned model, uses this uncertainty estimate as a reward penalty, and trains a policy using MBPO in this uncertainty-penalized MDP.

**Performance:**

MOPO is the strongest by a significant margin on all the mixed datasets and most of the medium-expert datasets, while also achieving strong performance on all of the random datasets.

The paper's arXiv identifier is arXiv:2005.13239, and the code is available at https://github.com/tianheyu927/mopo.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "657a7137-7d08-4596-9b86-eb2518f4816b",
  "tool_use_result": {
    "query": "MOPO Yu et al NeurIPS 2020 arXiv model-based offline policy optimization",
    "results": [
      {
        "tool_use_id": "srvtoolu_01EwC6jiq3gbvWSUMxb7tTUZ",
        "content": [
          {
            "title": "MOPO: Model-based Offline Policy Optimization",
            "url": "https://arxiv.org/pdf/2005.13239"
          },
          {
            "title": "MOPO: Model-based Offline Policy Optimization",
            "url": "https://proceedings.neurips.cc/paper_files/paper/2020/hash/a322852ce0df73e204b7e67cbbef0d0a-Abstract.html"
          },
          {
            "title": "MOPO: Model-based Offline Policy Optimization",
            "url": "https://proceedings.nips.cc/paper/2020/file/a322852ce0df73e204b7e67cbbef0d0a-Paper.pdf"
          },
          {
            "title": "MOPO: Model-based Offline Policy Optimization - ADS",
            "url": "https://ui.adsabs.harvard.edu/abs/2020arXiv200513239Y/abstract"
          },
          {
            "title": "Offline Model-Based Optimization via Policy-Guided Gradient Search",
            "url": "https://arxiv.org/html/2405.05349v1"
          },
          {
            "title": "Review for NeurIPS paper: MOPO: Model-based Offline Policy Optimization",
            "url": "https://proceedings.neurips.cc/paper/2020/file/a322852ce0df73e204b7e67cbbef0d0a-Review.html"
          },
          {
            "title": "Model-based Policy Optimization with Unsupervised Model Adaptation",
            "url": "https://proceedings.neurips.cc/paper/2020/file/1dc3a89d0d440ba31729b0ba74b93a33-Paper.pdf"
          },
          {
            "title": "[2005.13239] MOPO: Model-based Offline Policy Optimization",
            "url": "https://arxiv.org/abs/2005.13239"
          },
          {
            "title": "MOPO: model-based offline policy optimization",
            "url": "https://dl.acm.org/doi/10.5555/3495724.3496909"
          },
          {
            "title": "MOPO: Model-based Offline Policy Optimization - Jianan Chen",
            "url": "https://gjiananchen.github.io/publications/MOPO"
          }
        ]
      },
      "I found comprehensive information about the MOPO paper. Here's what the search reveals:\n\nMOPO was presented at the 34th Conference on Neural Information Processing Systems (NeurIPS 2020) in Vancouver, Canada.\n\n**Key Details:**\n\nThe paper was authored by Tianhe Yu, Garrett Thomas, Lantao Yu, Stefano Ermon, James Zou, Sergey Levine, Chelsea Finn, and Tengyu Ma.\n\n**Main Contribution:**\n\nThe primary contribution is an offline model-based RL algorithm that optimizes a policy in an uncertainty-penalized MDP, where the reward function is penalized by an estimate of the model's error. Under this new MDP, the authors theoretically show that they maximize a lower bound of the return in the true MDP, and find the optimal trade-off between the return and the risk.\n\n**Algorithm:**\n\nThe practical method estimates model error using the predicted variance of a learned model, uses this uncertainty estimate as a reward penalty, and trains a policy using MBPO in this uncertainty-penalized MDP.\n\n**Performance:**\n\nMOPO is the strongest by a significant margin on all the mixed datasets and most of the medium-expert datasets, while also achieving strong performance on all of the random datasets.\n\nThe paper's arXiv identifier is arXiv:2005.13239, and the code is available at https://github.com/tianheyu927/mopo."
    ],
    "durationSeconds": 6.819428734000001
  }
}
```

</details>

---

### Assistant

_source line 14_

<details><summary>Logged reasoning block</summary>

```text
I now have all the information I need:

1. **TD-MPC2**: Hansen N., Su H., Wang X. (ICLR 2024), arXiv:2310.16828
2. **MOPO**: Yu T., Thomas G., Yu L., Ermon S., Zou J., Levine S., Finn C., Ma T. (NeurIPS 2020), arXiv:2005.13239

Now I need to:
1. Add these 2 new papers
2. Change 5 papers from `direct-competitor` to `background`: IRIS, TWM, TransDreamer, NE-Dreamer, DyMoDreamer


3. I'm locating the literature map file and preparing the edits—I'll reclassify the five papers first, then insert the new entries. I'm identifying the unique context strings for each category change—each paper has a distinct `paper_id` line I can use as an anchor. For the two new papers, I'll insert TD-MPC2 in the model-predictive control section and MOPO near the value overestimation content, then execute all five category updates and both additions. I'm identifying the specific entries to modify by including their paper_id and venue information to ensure each edit targets the right location uniquely. For the new papers, I need to figure out the best placement—TD-MPC2 goes after the MPC section ends, while MOPO fits better either after the MBPO entry or in its own section depending on the structure. I'll place TD-MPC2 at the end of the MPC section and create a separate mini-section for MOPO right after, since pessimistic MBRL deserves its own space. Let me make those edits now.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "0f19a6b6-ad1c-4953-b6ce-e6884fe2fa60",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ARLrV8EKT83QNmG4vKS6V7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9579,
      "cache_read_input_tokens": 24502,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9579
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

_source line 15_

Got the file and paper info. Now applying all changes: 5 category changes + 2 new entries.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "d6037007-da85-4acd-a018-df3a4f7167b1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ARLrV8EKT83QNmG4vKS6V7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9579,
      "cache_read_input_tokens": 24502,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9579
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

_source line 16_

<details open><summary>🔧 Tool call — Edit · `toolu_01Kjh3rcBPUMS41fEJVGgtjL`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "- paper_id: micheli2023iris\n  title: \"Transformers are Sample-Efficient World Models\"\n  authors: [Micheli V., Alonso E., Fleuret F.]\n  year: 2023\n  venue: ICLR\n  category: direct-competitor\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"",
  "new_string": "- paper_id: micheli2023iris\n  title: \"Transformers are Sample-Efficient World Models\"\n  authors: [Micheli V., Alonso E., Fleuret F.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "f69ad90c-1143-468c-9e2b-8ec36b6a3dbb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ARLrV8EKT83QNmG4vKS6V7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9579,
      "cache_read_input_tokens": 24502,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9579
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

_source line 17 · 2026-05-14T14:57:20.598Z_

<details><summary>↩ Tool result · reported error · `toolu_01Kjh3rcBPUMS41fEJVGgtjL`</summary>

```text
&lt;tool_use_error>File has not been read yet. Read it first before writing to it.&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "83079259-6feb-465c-aaf4-3670d7a122a9",
  "tool_use_result": "Error: File has not been read yet. Read it first before writing to it."
}
```

</details>

---

### Tool call

_source line 18_

<details open><summary>🔧 Tool call — Edit · `toolu_01Go69NvxvZnzboLEsDnjWZW`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "- paper_id: robine2023twm\n  title: \"Transformer-based World Models Are Happy With 100k Interactions\"\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\n  year: 2023\n  venue: ICLR\n  category: direct-competitor\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"",
  "new_string": "- paper_id: robine2023twm\n  title: \"Transformer-based World Models Are Happy With 100k Interactions\"\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "25555306-92ef-42b4-af72-0cff7ccdb3a1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ARLrV8EKT83QNmG4vKS6V7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9579,
      "cache_read_input_tokens": 24502,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9579
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

_source line 19 · 2026-05-14T14:57:24.277Z_

<details><summary>↩ Tool result · reported error · `toolu_01Go69NvxvZnzboLEsDnjWZW`</summary>

```text
&lt;tool_use_error>File has not been read yet. Read it first before writing to it.&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "ce182d25-2349-4a6c-bf75-f80808f7175d",
  "tool_use_result": "Error: File has not been read yet. Read it first before writing to it."
}
```

</details>

---

### Tool call

_source line 20_

<details open><summary>🔧 Tool call — Edit · `toolu_01BSEHVJ2exkchfyaiRzEGYM`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "- paper_id: chen2022transdreamer\n  title: \"TransDreamer: Reinforcement Learning with Transformer World Models\"\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\n  year: 2022\n  venue: \"arXiv:2202.09481\"\n  category: direct-competitor\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"",
  "new_string": "- paper_id: chen2022transdreamer\n  title: \"TransDreamer: Reinforcement Learning with Transformer World Models\"\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\n  year: 2022\n  venue: \"arXiv:2202.09481\"\n  category: background\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "127b6a56-24c8-45ef-a68e-1927f022a04e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ARLrV8EKT83QNmG4vKS6V7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9579,
      "cache_read_input_tokens": 24502,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9579
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

_source line 21 · 2026-05-14T14:57:27.777Z_

<details><summary>↩ Tool result · reported error · `toolu_01BSEHVJ2exkchfyaiRzEGYM`</summary>

```text
&lt;tool_use_error>File has not been read yet. Read it first before writing to it.&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "6d4b185d-89ae-4848-87d3-c4e1e6c34bf1",
  "tool_use_result": "Error: File has not been read yet. Read it first before writing to it."
}
```

</details>

---

### Tool call

_source line 22_

<details open><summary>🔧 Tool call — Edit · `toolu_01C39RDANJN1yRQwtpQP9nGo`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "- paper_id: bredis2026nedreamer\n  title: \"Next Embedding Prediction Makes World Models Stronger\"\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\n  year: 2026\n  venue: \"arXiv:2603.02765\"\n  category: direct-competitor\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"",
  "new_string": "- paper_id: bredis2026nedreamer\n  title: \"Next Embedding Prediction Makes World Models Stronger\"\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\n  year: 2026\n  venue: \"arXiv:2603.02765\"\n  category: background\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "2bd4e1f6-3d59-414d-a135-413d1aec6923",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ARLrV8EKT83QNmG4vKS6V7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9579,
      "cache_read_input_tokens": 24502,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9579
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

_source line 23 · 2026-05-14T14:57:31.728Z_

<details><summary>↩ Tool result · reported error · `toolu_01C39RDANJN1yRQwtpQP9nGo`</summary>

```text
&lt;tool_use_error>File has not been read yet. Read it first before writing to it.&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "22e78dba-b8d5-4c40-a548-408edfc3bbd9",
  "tool_use_result": "Error: File has not been read yet. Read it first before writing to it."
}
```

</details>

---

### Tool call

_source line 24_

<details open><summary>🔧 Tool call — Edit · `toolu_01BJqhERUoXRXnYTKtSoiPT2`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "- paper_id: zhang2025dymodreamer\n  title: \"DyMoDreamer: World Modeling with Dynamic Modulation\"\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\n  year: 2025\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"",
  "new_string": "- paper_id: zhang2025dymodreamer\n  title: \"DyMoDreamer: World Modeling with Dynamic Modulation\"\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\n  year: 2025\n  venue: NeurIPS\n  category: background\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "ed9a78bc-326a-481e-9dff-8a6af3527482",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ARLrV8EKT83QNmG4vKS6V7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9579,
      "cache_read_input_tokens": 24502,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9579
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

_source line 25 · 2026-05-14T14:57:35.079Z_

<details><summary>↩ Tool result · reported error · `toolu_01BJqhERUoXRXnYTKtSoiPT2`</summary>

```text
&lt;tool_use_error>File has not been read yet. Read it first before writing to it.&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "edd50399-f6b7-419e-bcf3-f749463cd62e",
  "tool_use_result": "Error: File has not been read yet. Read it first before writing to it."
}
```

</details>

---

### Assistant

_source line 26_

Need to read the file first via the Read tool.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "929e1c47-cc0b-4f0d-8f56-45fe9df09d88",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01P9jiuhpLupfcLUU1dS83Qo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3892,
      "cache_read_input_tokens": 34081,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3892
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

### Tool call

_source line 27_

<details open><summary>🔧 Tool call — Read · `toolu_01XUscFc6Jt1XQUWJgKP6B4p`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "770638ca-2a3e-44ad-bcdb-e047e4c0c5fc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01P9jiuhpLupfcLUU1dS83Qo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3892,
      "cache_read_input_tokens": 34081,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3892
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

### Tool result

_source line 28 · 2026-05-14T14:57:38.326Z_

<details><summary>↩ Tool result · `toolu_01XUscFc6Jt1XQUWJgKP6B4p`</summary>

```text
1	# Literature Map — event-gated-adaptive-horizon
2	# Last updated: 2026-05-14
3	# Total: 43 papers (5 existing + 38 new)
4	
5	# ============================================================
6	# EXISTING CITATIONS (already in paper.tex)
7	# ============================================================
8	
9	- paper_id: sutton1999options
10	  title: "Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning"
11	  authors: [Sutton R.S., Precup D., Singh S.]
12	  year: 1999
13	  venue: "Artificial Intelligence 112(1-2):181-211"
14	  category: background
15	  role: "Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL"
16	  relevance_score: 5
17	
18	- paper_id: hafner2020dreamerv1
19	  title: "Dream to Control: Learning Behaviors by Latent Imagination"
20	  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]
21	  year: 2020
22	  venue: ICLR
23	  category: background
24	  role: "DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm"
25	  relevance_score: 5
26	
27	- paper_id: hafner2023dreamerv3
28	  title: "Mastering Diverse Domains through World Models"
29	  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]
30	  year: 2023
31	  venue: "arXiv:2301.04104 (Nature 2025)"
32	  category: background
33	  role: "DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here"
34	  relevance_score: 5
35	
36	- paper_id: sharma2017figar
37	  title: "Fine Grained Action Repetition for Deep Reinforcement Learning"
38	  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]
39	  year: 2017
40	  venue: "ICLR Workshop"
41	  category: method-component
42	  role: "FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL"
43	  relevance_score: 4
44	
45	- paper_id: janner2019mbpo
46	  title: "When to Trust Your Model: Model-Based Policy Optimization"
47	  authors: [Janner M., Fu J., Zhang M., Levine S.]
48	  year: 2019
49	  venue: NeurIPS
50	  category: background
51	  role: "MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding"
52	  relevance_score: 5
53	
54	# ============================================================
55	# NEW: Multi-step prediction error compounding
56	# ============================================================
57	
58	- paper_id: ke2019learning
59	  title: "Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future"
60	  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]
61	  year: 2019
62	  venue: ICLR
63	  category: background
64	  role: "Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1"
65	  relevance_score: 4
66	
67	- paper_id: asadi2019combating
68	  title: "Combating the Compounding-Error Problem with a Multi-step Model"
69	  authors: [Asadi K., Misra D., Kim S., Littman M.L.]
70	  year: 2019
71	  venue: "arXiv:1905.13320"
72	  category: background
73	  role: "Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error"
74	  relevance_score: 4
75	
76	- paper_id: venkatraman2015improving
77	  title: "Improving Multi-Step Prediction of Learned Time Series Models"
78	  authors: [Venkatraman A., Hebert M., Bagnell J.A.]
79	  year: 2015
80	  venue: AAAI
81	  category: background
82	  role: "Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error"
83	  relevance_score: 3
84	
85	- paper_id: lambert2022investigating
86	  title: "Investigating Compounding Prediction Errors in Learned Dynamics Models"
87	  authors: [Lambert N., Pister K.S.J., Calandra R.]
88	  year: 2022
89	  venue: "arXiv:2203.09637"
90	  category: background
91	  role: "Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead"
92	  relevance_score: 3
93	
94	# ============================================================
95	# NEW: Model-predictive control with learned dynamics
96	# ============================================================
97	
98	- paper_id: chua2018pets
99	  title: "Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models"
100	  authors: [Chua K., Calandra R., McAllister R., Levine S.]
101	  year: 2018
102	  venue: NeurIPS
103	  category: background
104	  role: "PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach"
105	  relevance_score: 3
106	
107	- paper_id: nagabandi2018neural
108	  title: "Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning"
109	  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]
110	  year: 2018
111	  venue: ICRA
112	  category: background
113	  role: "Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures"
114	  relevance_score: 3
115	
116	# ============================================================
117	# NEW: Value overestimation mitigation
118	# ============================================================
119	
120	- paper_id: thrun1993issues
121	  title: "Issues in Using Function Approximation for Reinforcement Learning"
122	  authors: [Thrun S., Schwartz A.]
123	  year: 1993
124	  venue: "Connectionist Models Summer School"
125	  category: background
126	  role: "First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning"
127	  relevance_score: 4
128	
129	- paper_id: vanhasselt2016double
130	  title: "Deep Reinforcement Learning with Double Q-Learning"
131	  authors: [van Hasselt H., Guez A., Silver D.]
132	  year: 2016
133	  venue: AAAI
134	  category: background
135	  role: "Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL"
136	  relevance_score: 4
137	
138	- paper_id: fujimoto2018td3
139	  title: "Addressing Function Approximation Error in Actor-Critic Methods"
140	  authors: [Fujimoto S., van Hoof H., Meger D.]
141	  year: 2018
142	  venue: ICML
143	  category: method-component
144	  role: "TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify"
145	  relevance_score: 4
146	
147	- paper_id: haarnoja2018sac
148	  title: "Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor"
149	  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]
150	  year: 2018
151	  venue: ICML
152	  category: method-component
153	  role: "SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values"
154	  relevance_score: 3
155	
156	- paper_id: lee2021sunrise
157	  title: "SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning"
158	  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]
159	  year: 2021
160	  venue: ICML
161	  category: method-component
162	  role: "Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism"
163	  relevance_score: 3
164	
165	# ============================================================
166	# NEW: Delusional bias
167	# ============================================================
168	
169	- paper_id: lu2018nondelusional
170	  title: "Non-delusional Q-learning and Value-Iteration"
171	  authors: [Lu T., Schuurmans D., Boutilier C.]
172	  year: 2018
173	  venue: NeurIPS
174	  category: background
175	  role: "Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision"
176	  relevance_score: 5
177	
178	# ============================================================
179	# NEW: Hierarchical RL with learned models
180	# ============================================================
181	
182	- paper_id: hafner2022director
183	  title: "Deep Hierarchical Planning from Pixels"
184	  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]
185	  year: 2022
186	  venue: NeurIPS
187	  category: direct-competitor
188	  role: "Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt"
189	  relevance_score: 4
190	
191	- paper_id: nachum2018hiro
192	  title: "Data-Efficient Hierarchical Reinforcement Learning"
193	  authors: [Nachum O., Gu S., Lee H., Levine S.]
194	  year: 2018
195	  venue: NeurIPS
196	  category: background
197	  role: "HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed"
198	  relevance_score: 3
199	
200	# ============================================================
201	# NEW: Action repeat / frame skip
202	# ============================================================
203	
204	- paper_id: braylan2015frame
205	  title: "Frame Skip Is a Powerful Parameter for Learning to Play Atari"
206	  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]
207	  year: 2015
208	  venue: "AAAI Workshop on Learning for General Competency in Video Games"
209	  category: background
210	  role: "Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice"
211	  relevance_score: 3
212	
213	- paper_id: lakshminarayanan2017dynamic
214	  title: "Dynamic Action Repetition for Deep Reinforcement Learning"
215	  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]
216	  year: 2017
217	  venue: AAAI
218	  category: method-component
219	  role: "Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach"
220	  relevance_score: 4
221	
222	- paper_id: biedenkapp2021temporl
223	  title: "TempoRL: Learning When to Act"
224	  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]
225	  year: 2021
226	  venue: ICML
227	  category: method-component
228	  role: "Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify"
229	  relevance_score: 4
230	
231	# ============================================================
232	# NEW: DreamerV2
233	# ============================================================
234	
235	- paper_id: hafner2021dreamerv2
236	  title: "Mastering Atari with Discrete World Models"
237	  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]
238	  year: 2021
239	  venue: ICLR
240	  category: background
241	  role: "DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system"
242	  relevance_score: 5
243	
244	# ============================================================
245	# NEW: Alternative world model architectures
246	# ============================================================
247	
248	- paper_id: micheli2023iris
249	  title: "Transformers are Sample-Efficient World Models"
250	  authors: [Micheli V., Alonso E., Fleuret F.]
251	  year: 2023
252	  venue: ICLR
253	  category: direct-competitor
254	  role: "IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction"
255	  relevance_score: 3
256	
257	- paper_id: robine2023twm
258	  title: "Transformer-based World Models Are Happy With 100k Interactions"
259	  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]
260	  year: 2023
261	  venue: ICLR
262	  category: direct-competitor
263	  role: "TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap"
264	  relevance_score: 3
265	
266	- paper_id: chen2022transdreamer
267	  title: "TransDreamer: Reinforcement Learning with Transformer World Models"
268	  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]
269	  year: 2022
270	  venue: "arXiv:2202.09481"
271	  category: direct-competitor
272	  role: "Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures"
273	  relevance_score: 3
274	
275	# ============================================================
276	# NEW: 2024-2026 concurrent work on temporal abstraction in world models
277	# ============================================================
278	
279	- paper_id: gumbsch2024thick
280	  title: "Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics"
281	  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]
282	  year: 2024
283	  venue: ICLR
284	  category: direct-competitor
285	  role: "THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination"
286	  relevance_score: 5
287	
288	- paper_id: mattes2024hieros
289	  title: "Hieros: Hierarchical Imagination on Structured State Space Sequence World Models"
290	  authors: [Mattes P., Schlosser R., Herbrich R.]
291	  year: 2024
292	  venue: ICML
293	  category: direct-competitor
294	  role: "Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify"
295	  relevance_score: 5
296	
297	# ============================================================
298	# NEW: Seed-dependent instability & value overestimation in MBRL
299	# ============================================================
300	
301	- paper_id: henderson2018deep
302	  title: "Deep Reinforcement Learning that Matters"
303	  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]
304	  year: 2018
305	  venue: AAAI
306	  category: background
307	  role: "Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config"
308	  relevance_score: 4
309	
310	- paper_id: nikishin2022primacy
311	  title: "The Primacy Bias in Deep Reinforcement Learning"
312	  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]
313	  year: 2022
314	  venue: ICML
315	  category: background
316	  role: "Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent"
317	  relevance_score: 4
318	
319	- paper_id: qiao2023mind
320	  title: "Mind the Model, Not the Agent: The Primacy Bias in Model-based RL"
321	  authors: [Qiao Z., Lyu J., Li X.]
322	  year: 2023
323	  venue: "arXiv:2310.15017 (ECAI 2024)"
324	  category: evaluation
325	  role: "Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't"
326	  relevance_score: 5
327	
328	- paper_id: hussing2024dissecting
329	  title: "Dissecting Deep RL with High Update Ratios: Combatting Value Divergence"
330	  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]
331	  year: 2024
332	  venue: "Reinforcement Learning Journal (RLC 2024)"
333	  category: evaluation
334	  role: "Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization"
335	  relevance_score: 4
336	
337	- paper_id: barkley2024stealing
338	  title: "Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning"
339	  authors: [Barkley B., Fridovich-Keil D.]
340	  year: 2024
341	  venue: "arXiv:2412.14312 (ICML 2025)"
342	  category: evaluation
343	  role: "Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix"
344	  relevance_score: 3
345	
346	- paper_id: bjorck2022variance
347	  title: "Is High Variance Unavoidable in RL? A Case Study in Continuous Control"
348	  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]
349	  year: 2022
350	  venue: ICLR
351	  category: background
352	  role: "Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability"
353	  relevance_score: 3
354	
355	# ============================================================
356	# NEW: Reward prediction quality → MBRL performance
357	# ============================================================
358	# Our key finding: removing dt_embedding causes reward_MAE to spike 75x
359	# (0.01 → 0.747), making performance seed-dependent. These papers
360	# establish that reward prediction quality is a known MBRL bottleneck.
361	
362	- paper_id: lee2024dreamsmooth
363	  title: "DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing"
364	  authors: [Lee V., Abbeel P., Lee Y.]
365	  year: 2024
366	  venue: ICLR
367	  category: background
368	  role: "Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x"
369	  relevance_score: 5
370	
371	- paper_id: ma2024harmonydream
372	  title: "HarmonyDream: Task Harmonization Inside World Models"
373	  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]
374	  year: 2024
375	  venue: ICML
376	  category: background
377	  role: "Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion"
378	  relevance_score: 5
379	
380	- paper_id: lambert2020objective
381	  title: "Objective Mismatch in Model-based Reinforcement Learning"
382	  authors: [Lambert N., Amos B., Yadan O., Calandra R.]
383	  year: 2020
384	  venue: "L4DC (Proceedings of Machine Learning Research, vol. 120)"
385	  category: background
386	  role: "Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch"
387	  relevance_score: 4
388	
389	# ============================================================
390	# NEW: Auxiliary tasks & representation coupling in world models
391	# ============================================================
392	# Our finding: reward prediction quality is tightly coupled to temporal
393	# conditioning (dt_embedding). Removing the embedding degrades the
394	# reward head while dynamics remain intact — suggesting the reward head
395	# acts as more than a passive predictor; it conditions the shared
396	# representation. Literature gap: no prior work studies this coupling
397	# specifically in Dreamer-family world models.
398	
399	- paper_id: jaderberg2017unreal
400	  title: "Reinforcement Learning with Unsupervised Auxiliary Tasks"
401	  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]
402	  year: 2017
403	  venue: ICLR
404	  category: background
405	  role: "UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction"
406	  relevance_score: 4
407	
408	- paper_id: lyle2021auxiliary
409	  title: "On The Effect of Auxiliary Tasks on Representation Dynamics"
410	  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]
411	  year: 2021
412	  venue: AISTATS
413	  category: background
414	  role: "Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space"
415	  relevance_score: 4
416	
417	# ============================================================
418	# NEW: DreamerV3 architecture improvements (2025-2026)
419	# ============================================================
420	
421	- paper_id: bredis2026nedreamer
422	  title: "Next Embedding Prediction Makes World Models Stronger"
423	  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]
424	  year: 2026
425	  venue: "arXiv:2603.02765"
426	  category: direct-competitor
427	  role: "NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis"
428	  relevance_score: 3
429	
430	- paper_id: zhang2025dymodreamer
431	  title: "DyMoDreamer: World Modeling with Dynamic Modulation"
432	  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]
433	  year: 2025
434	  venue: NeurIPS
435	  category: direct-competitor
436	  role: "Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation"
437	  relevance_score: 3
438	
439	# ============================================================
440	# NEW: Temporal abstraction methods
441	# ============================================================
442	
443	- paper_id: liu2025vanta
444	  title: "Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning"
445	  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]
446	  year: 2025
447	  venue: ICLR
448	  category: method-component
449	  role: "VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps"
450	  relevance_score: 3
451	
452	# ============================================================
453	# NEW: Evaluation methodology
454	# ============================================================
455	
456	- paper_id: agarwal2021precipice
457	  title: "Deep Reinforcement Learning at the Edge of the Statistical Precipice"
458	  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]
459	  year: 2021
460	  venue: NeurIPS
461	  category: evaluation
462	  role: "Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds"
463	  relevance_score: 4
464	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "6ae00f62-0d9a-462e-849e-828ee027d3b4",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
      "content": "# Literature Map — event-gated-adaptive-horizon\n# Last updated: 2026-05-14\n# Total: 43 papers (5 existing + 38 new)\n\n# ============================================================\n# EXISTING CITATIONS (already in paper.tex)\n# ============================================================\n\n- paper_id: sutton1999options\n  title: \"Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning\"\n  authors: [Sutton R.S., Precup D., Singh S.]\n  year: 1999\n  venue: \"Artificial Intelligence 112(1-2):181-211\"\n  category: background\n  role: \"Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL\"\n  relevance_score: 5\n\n- paper_id: hafner2020dreamerv1\n  title: \"Dream to Control: Learning Behaviors by Latent Imagination\"\n  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]\n  year: 2020\n  venue: ICLR\n  category: background\n  role: \"DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm\"\n  relevance_score: 5\n\n- paper_id: hafner2023dreamerv3\n  title: \"Mastering Diverse Domains through World Models\"\n  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]\n  year: 2023\n  venue: \"arXiv:2301.04104 (Nature 2025)\"\n  category: background\n  role: \"DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here\"\n  relevance_score: 5\n\n- paper_id: sharma2017figar\n  title: \"Fine Grained Action Repetition for Deep Reinforcement Learning\"\n  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]\n  year: 2017\n  venue: \"ICLR Workshop\"\n  category: method-component\n  role: \"FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL\"\n  relevance_score: 4\n\n- paper_id: janner2019mbpo\n  title: \"When to Trust Your Model: Model-Based Policy Optimization\"\n  authors: [Janner M., Fu J., Zhang M., Levine S.]\n  year: 2019\n  venue: NeurIPS\n  category: background\n  role: \"MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Multi-step prediction error compounding\n# ============================================================\n\n- paper_id: ke2019learning\n  title: \"Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future\"\n  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]\n  year: 2019\n  venue: ICLR\n  category: background\n  role: \"Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1\"\n  relevance_score: 4\n\n- paper_id: asadi2019combating\n  title: \"Combating the Compounding-Error Problem with a Multi-step Model\"\n  authors: [Asadi K., Misra D., Kim S., Littman M.L.]\n  year: 2019\n  venue: \"arXiv:1905.13320\"\n  category: background\n  role: \"Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error\"\n  relevance_score: 4\n\n- paper_id: venkatraman2015improving\n  title: \"Improving Multi-Step Prediction of Learned Time Series Models\"\n  authors: [Venkatraman A., Hebert M., Bagnell J.A.]\n  year: 2015\n  venue: AAAI\n  category: background\n  role: \"Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error\"\n  relevance_score: 3\n\n- paper_id: lambert2022investigating\n  title: \"Investigating Compounding Prediction Errors in Learned Dynamics Models\"\n  authors: [Lambert N., Pister K.S.J., Calandra R.]\n  year: 2022\n  venue: \"arXiv:2203.09637\"\n  category: background\n  role: \"Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Model-predictive control with learned dynamics\n# ============================================================\n\n- paper_id: chua2018pets\n  title: \"Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models\"\n  authors: [Chua K., Calandra R., McAllister R., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach\"\n  relevance_score: 3\n\n- paper_id: nagabandi2018neural\n  title: \"Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning\"\n  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]\n  year: 2018\n  venue: ICRA\n  category: background\n  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================\n\n- paper_id: thrun1993issues\n  title: \"Issues in Using Function Approximation for Reinforcement Learning\"\n  authors: [Thrun S., Schwartz A.]\n  year: 1993\n  venue: \"Connectionist Models Summer School\"\n  category: background\n  role: \"First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning\"\n  relevance_score: 4\n\n- paper_id: vanhasselt2016double\n  title: \"Deep Reinforcement Learning with Double Q-Learning\"\n  authors: [van Hasselt H., Guez A., Silver D.]\n  year: 2016\n  venue: AAAI\n  category: background\n  role: \"Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL\"\n  relevance_score: 4\n\n- paper_id: fujimoto2018td3\n  title: \"Addressing Function Approximation Error in Actor-Critic Methods\"\n  authors: [Fujimoto S., van Hoof H., Meger D.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify\"\n  relevance_score: 4\n\n- paper_id: haarnoja2018sac\n  title: \"Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor\"\n  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values\"\n  relevance_score: 3\n\n- paper_id: lee2021sunrise\n  title: \"SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning\"\n  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Delusional bias\n# ============================================================\n\n- paper_id: lu2018nondelusional\n  title: \"Non-delusional Q-learning and Value-Iteration\"\n  authors: [Lu T., Schuurmans D., Boutilier C.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Hierarchical RL with learned models\n# ============================================================\n\n- paper_id: hafner2022director\n  title: \"Deep Hierarchical Planning from Pixels\"\n  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]\n  year: 2022\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt\"\n  relevance_score: 4\n\n- paper_id: nachum2018hiro\n  title: \"Data-Efficient Hierarchical Reinforcement Learning\"\n  authors: [Nachum O., Gu S., Lee H., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Action repeat / frame skip\n# ============================================================\n\n- paper_id: braylan2015frame\n  title: \"Frame Skip Is a Powerful Parameter for Learning to Play Atari\"\n  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]\n  year: 2015\n  venue: \"AAAI Workshop on Learning for General Competency in Video Games\"\n  category: background\n  role: \"Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice\"\n  relevance_score: 3\n\n- paper_id: lakshminarayanan2017dynamic\n  title: \"Dynamic Action Repetition for Deep Reinforcement Learning\"\n  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]\n  year: 2017\n  venue: AAAI\n  category: method-component\n  role: \"Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach\"\n  relevance_score: 4\n\n- paper_id: biedenkapp2021temporl\n  title: \"TempoRL: Learning When to Act\"\n  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV2\n# ============================================================\n\n- paper_id: hafner2021dreamerv2\n  title: \"Mastering Atari with Discrete World Models\"\n  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]\n  year: 2021\n  venue: ICLR\n  category: background\n  role: \"DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Alternative world model architectures\n# ============================================================\n\n- paper_id: micheli2023iris\n  title: \"Transformers are Sample-Efficient World Models\"\n  authors: [Micheli V., Alonso E., Fleuret F.]\n  year: 2023\n  venue: ICLR\n  category: direct-competitor\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"\n  relevance_score: 3\n\n- paper_id: robine2023twm\n  title: \"Transformer-based World Models Are Happy With 100k Interactions\"\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\n  year: 2023\n  venue: ICLR\n  category: direct-competitor\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"\n  relevance_score: 3\n\n- paper_id: chen2022transdreamer\n  title: \"TransDreamer: Reinforcement Learning with Transformer World Models\"\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\n  year: 2022\n  venue: \"arXiv:2202.09481\"\n  category: direct-competitor\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: 2024-2026 concurrent work on temporal abstraction in world models\n# ============================================================\n\n- paper_id: gumbsch2024thick\n  title: \"Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics\"\n  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]\n  year: 2024\n  venue: ICLR\n  category: direct-competitor\n  role: \"THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination\"\n  relevance_score: 5\n\n- paper_id: mattes2024hieros\n  title: \"Hieros: Hierarchical Imagination on Structured State Space Sequence World Models\"\n  authors: [Mattes P., Schlosser R., Herbrich R.]\n  year: 2024\n  venue: ICML\n  category: direct-competitor\n  role: \"Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Seed-dependent instability & value overestimation in MBRL\n# ============================================================\n\n- paper_id: henderson2018deep\n  title: \"Deep Reinforcement Learning that Matters\"\n  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]\n  year: 2018\n  venue: AAAI\n  category: background\n  role: \"Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config\"\n  relevance_score: 4\n\n- paper_id: nikishin2022primacy\n  title: \"The Primacy Bias in Deep Reinforcement Learning\"\n  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]\n  year: 2022\n  venue: ICML\n  category: background\n  role: \"Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent\"\n  relevance_score: 4\n\n- paper_id: qiao2023mind\n  title: \"Mind the Model, Not the Agent: The Primacy Bias in Model-based RL\"\n  authors: [Qiao Z., Lyu J., Li X.]\n  year: 2023\n  venue: \"arXiv:2310.15017 (ECAI 2024)\"\n  category: evaluation\n  role: \"Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't\"\n  relevance_score: 5\n\n- paper_id: hussing2024dissecting\n  title: \"Dissecting Deep RL with High Update Ratios: Combatting Value Divergence\"\n  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]\n  year: 2024\n  venue: \"Reinforcement Learning Journal (RLC 2024)\"\n  category: evaluation\n  role: \"Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization\"\n  relevance_score: 4\n\n- paper_id: barkley2024stealing\n  title: \"Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning\"\n  authors: [Barkley B., Fridovich-Keil D.]\n  year: 2024\n  venue: \"arXiv:2412.14312 (ICML 2025)\"\n  category: evaluation\n  role: \"Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix\"\n  relevance_score: 3\n\n- paper_id: bjorck2022variance\n  title: \"Is High Variance Unavoidable in RL? A Case Study in Continuous Control\"\n  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]\n  year: 2022\n  venue: ICLR\n  category: background\n  role: \"Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Reward prediction quality → MBRL performance\n# ============================================================\n# Our key finding: removing dt_embedding causes reward_MAE to spike 75x\n# (0.01 → 0.747), making performance seed-dependent. These papers\n# establish that reward prediction quality is a known MBRL bottleneck.\n\n- paper_id: lee2024dreamsmooth\n  title: \"DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing\"\n  authors: [Lee V., Abbeel P., Lee Y.]\n  year: 2024\n  venue: ICLR\n  category: background\n  role: \"Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x\"\n  relevance_score: 5\n\n- paper_id: ma2024harmonydream\n  title: \"HarmonyDream: Task Harmonization Inside World Models\"\n  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]\n  year: 2024\n  venue: ICML\n  category: background\n  role: \"Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion\"\n  relevance_score: 5\n\n- paper_id: lambert2020objective\n  title: \"Objective Mismatch in Model-based Reinforcement Learning\"\n  authors: [Lambert N., Amos B., Yadan O., Calandra R.]\n  year: 2020\n  venue: \"L4DC (Proceedings of Machine Learning Research, vol. 120)\"\n  category: background\n  role: \"Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Auxiliary tasks & representation coupling in world models\n# ============================================================\n# Our finding: reward prediction quality is tightly coupled to temporal\n# conditioning (dt_embedding). Removing the embedding degrades the\n# reward head while dynamics remain intact — suggesting the reward head\n# acts as more than a passive predictor; it conditions the shared\n# representation. Literature gap: no prior work studies this coupling\n# specifically in Dreamer-family world models.\n\n- paper_id: jaderberg2017unreal\n  title: \"Reinforcement Learning with Unsupervised Auxiliary Tasks\"\n  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]\n  year: 2017\n  venue: ICLR\n  category: background\n  role: \"UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction\"\n  relevance_score: 4\n\n- paper_id: lyle2021auxiliary\n  title: \"On The Effect of Auxiliary Tasks on Representation Dynamics\"\n  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]\n  year: 2021\n  venue: AISTATS\n  category: background\n  role: \"Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV3 architecture improvements (2025-2026)\n# ============================================================\n\n- paper_id: bredis2026nedreamer\n  title: \"Next Embedding Prediction Makes World Models Stronger\"\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\n  year: 2026\n  venue: \"arXiv:2603.02765\"\n  category: direct-competitor\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"\n  relevance_score: 3\n\n- paper_id: zhang2025dymodreamer\n  title: \"DyMoDreamer: World Modeling with Dynamic Modulation\"\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\n  year: 2025\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Temporal abstraction methods\n# ============================================================\n\n- paper_id: liu2025vanta\n  title: \"Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning\"\n  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]\n  year: 2025\n  venue: ICLR\n  category: method-component\n  role: \"VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Evaluation methodology\n# ============================================================\n\n- paper_id: agarwal2021precipice\n  title: \"Deep Reinforcement Learning at the Edge of the Statistical Precipice\"\n  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]\n  year: 2021\n  venue: NeurIPS\n  category: evaluation\n  role: \"Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds\"\n  relevance_score: 4\n",
      "numLines": 464,
      "startLine": 1,
      "totalLines": 464
    }
  }
}
```

</details>

---

### Assistant

_source line 29_

<details><summary>Logged reasoning block</summary>

```text
Now I can do all the edits. Let me do all 7 edits in parallel: 5 category changes + 2 new paper additions.

For adding TD-MPC2, I'll add it after nagabandi2018neural (end of MPC section, before the Value overestimation section).
For adding MOPO, I'll add it right after TD-MPC2 in a new mini-section, or... actually, MOPO fits well as a new section about pessimistic MBRL, right after the MPC section. Let me add both after the MPC section.


Actually, let me reconsider the placement. TD-MPC2 belongs in the MPC section since it's a planning-based approach, while MOPO should get its own section on pessimistic MBRL between MPC and Value overestimation. Now I'll construct the edit to insert TD-MPC2 at the end of the MPC section.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "bfc75346-eaea-41e1-b206-318c0cea88bd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BwgraSDAtZjh6JQnUjmhuw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7658,
      "cache_read_input_tokens": 37973,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7658
      },
      "output_tokens": 10,
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

_source line 30_

Now applying all 7 edits in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "bcdc7c96-916f-4190-9727-899fe4aaf3ac",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BwgraSDAtZjh6JQnUjmhuw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7658,
      "cache_read_input_tokens": 37973,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7658
      },
      "output_tokens": 10,
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

_source line 31_

<details open><summary>🔧 Tool call — Edit · `toolu_01UT6DxNAcxeS51PDqzQV7ML`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "  category: direct-competitor\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"",
  "new_string": "  category: background\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "6f880e68-fc6d-4d54-9869-0d7a94b36f4c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BwgraSDAtZjh6JQnUjmhuw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7658,
      "cache_read_input_tokens": 37973,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7658
      },
      "output_tokens": 10,
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

_source line 32 · 2026-05-14T14:57:50.328Z_

<details><summary>↩ Tool result · `toolu_01UT6DxNAcxeS51PDqzQV7ML`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "a7f0fcd8-b570-45f9-b227-fea5ef1fdf55",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
    "oldString": "  category: direct-competitor\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"",
    "newString": "  category: background\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"",
    "originalFile": "# Literature Map — event-gated-adaptive-horizon\n# Last updated: 2026-05-14\n# Total: 43 papers (5 existing + 38 new)\n\n# ============================================================\n# EXISTING CITATIONS (already in paper.tex)\n# ============================================================\n\n- paper_id: sutton1999options\n  title: \"Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning\"\n  authors: [Sutton R.S., Precup D., Singh S.]\n  year: 1999\n  venue: \"Artificial Intelligence 112(1-2):181-211\"\n  category: background\n  role: \"Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL\"\n  relevance_score: 5\n\n- paper_id: hafner2020dreamerv1\n  title: \"Dream to Control: Learning Behaviors by Latent Imagination\"\n  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]\n  year: 2020\n  venue: ICLR\n  category: background\n  role: \"DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm\"\n  relevance_score: 5\n\n- paper_id: hafner2023dreamerv3\n  title: \"Mastering Diverse Domains through World Models\"\n  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]\n  year: 2023\n  venue: \"arXiv:2301.04104 (Nature 2025)\"\n  category: background\n  role: \"DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here\"\n  relevance_score: 5\n\n- paper_id: sharma2017figar\n  title: \"Fine Grained Action Repetition for Deep Reinforcement Learning\"\n  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]\n  year: 2017\n  venue: \"ICLR Workshop\"\n  category: method-component\n  role: \"FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL\"\n  relevance_score: 4\n\n- paper_id: janner2019mbpo\n  title: \"When to Trust Your Model: Model-Based Policy Optimization\"\n  authors: [Janner M., Fu J., Zhang M., Levine S.]\n  year: 2019\n  venue: NeurIPS\n  category: background\n  role: \"MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Multi-step prediction error compounding\n# ============================================================\n\n- paper_id: ke2019learning\n  title: \"Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future\"\n  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]\n  year: 2019\n  venue: ICLR\n  category: background\n  role: \"Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1\"\n  relevance_score: 4\n\n- paper_id: asadi2019combating\n  title: \"Combating the Compounding-Error Problem with a Multi-step Model\"\n  authors: [Asadi K., Misra D., Kim S., Littman M.L.]\n  year: 2019\n  venue: \"arXiv:1905.13320\"\n  category: background\n  role: \"Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error\"\n  relevance_score: 4\n\n- paper_id: venkatraman2015improving\n  title: \"Improving Multi-Step Prediction of Learned Time Series Models\"\n  authors: [Venkatraman A., Hebert M., Bagnell J.A.]\n  year: 2015\n  venue: AAAI\n  category: background\n  role: \"Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error\"\n  relevance_score: 3\n\n- paper_id: lambert2022investigating\n  title: \"Investigating Compounding Prediction Errors in Learned Dynamics Models\"\n  authors: [Lambert N., Pister K.S.J., Calandra R.]\n  year: 2022\n  venue: \"arXiv:2203.09637\"\n  category: background\n  role: \"Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Model-predictive control with learned dynamics\n# ============================================================\n\n- paper_id: chua2018pets\n  title: \"Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models\"\n  authors: [Chua K., Calandra R., McAllister R., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach\"\n  relevance_score: 3\n\n- paper_id: nagabandi2018neural\n  title: \"Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning\"\n  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]\n  year: 2018\n  venue: ICRA\n  category: background\n  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================\n\n- paper_id: thrun1993issues\n  title: \"Issues in Using Function Approximation for Reinforcement Learning\"\n  authors: [Thrun S., Schwartz A.]\n  year: 1993\n  venue: \"Connectionist Models Summer School\"\n  category: background\n  role: \"First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning\"\n  relevance_score: 4\n\n- paper_id: vanhasselt2016double\n  title: \"Deep Reinforcement Learning with Double Q-Learning\"\n  authors: [van Hasselt H., Guez A., Silver D.]\n  year: 2016\n  venue: AAAI\n  category: background\n  role: \"Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL\"\n  relevance_score: 4\n\n- paper_id: fujimoto2018td3\n  title: \"Addressing Function Approximation Error in Actor-Critic Methods\"\n  authors: [Fujimoto S., van Hoof H., Meger D.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify\"\n  relevance_score: 4\n\n- paper_id: haarnoja2018sac\n  title: \"Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor\"\n  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values\"\n  relevance_score: 3\n\n- paper_id: lee2021sunrise\n  title: \"SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning\"\n  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Delusional bias\n# ============================================================\n\n- paper_id: lu2018nondelusional\n  title: \"Non-delusional Q-learning and Value-Iteration\"\n  authors: [Lu T., Schuurmans D., Boutilier C.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Hierarchical RL with learned models\n# ============================================================\n\n- paper_id: hafner2022director\n  title: \"Deep Hierarchical Planning from Pixels\"\n  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]\n  year: 2022\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt\"\n  relevance_score: 4\n\n- paper_id: nachum2018hiro\n  title: \"Data-Efficient Hierarchical Reinforcement Learning\"\n  authors: [Nachum O., Gu S., Lee H., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Action repeat / frame skip\n# ============================================================\n\n- paper_id: braylan2015frame\n  title: \"Frame Skip Is a Powerful Parameter for Learning to Play Atari\"\n  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]\n  year: 2015\n  venue: \"AAAI Workshop on Learning for General Competency in Video Games\"\n  category: background\n  role: \"Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice\"\n  relevance_score: 3\n\n- paper_id: lakshminarayanan2017dynamic\n  title: \"Dynamic Action Repetition for Deep Reinforcement Learning\"\n  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]\n  year: 2017\n  venue: AAAI\n  category: method-component\n  role: \"Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach\"\n  relevance_score: 4\n\n- paper_id: biedenkapp2021temporl\n  title: \"TempoRL: Learning When to Act\"\n  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV2\n# ============================================================\n\n- paper_id: hafner2021dreamerv2\n  title: \"Mastering Atari with Discrete World Models\"\n  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]\n  year: 2021\n  venue: ICLR\n  category: background\n  role: \"DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Alternative world model architectures\n# ============================================================\n\n- paper_id: micheli2023iris\n  title: \"Transformers are Sample-Efficient World Models\"\n  authors: [Micheli V., Alonso E., Fleuret F.]\n  year: 2023\n  venue: ICLR\n  category: direct-competitor\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"\n  relevance_score: 3\n\n- paper_id: robine2023twm\n  title: \"Transformer-based World Models Are Happy With 100k Interactions\"\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\n  year: 2023\n  venue: ICLR\n  category: direct-competitor\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"\n  relevance_score: 3\n\n- paper_id: chen2022transdreamer\n  title: \"TransDreamer: Reinforcement Learning with Transformer World Models\"\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\n  year: 2022\n  venue: \"arXiv:2202.09481\"\n  category: direct-competitor\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: 2024-2026 concurrent work on temporal abstraction in world models\n# ============================================================\n\n- paper_id: gumbsch2024thick\n  title: \"Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics\"\n  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]\n  year: 2024\n  venue: ICLR\n  category: direct-competitor\n  role: \"THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination\"\n  relevance_score: 5\n\n- paper_id: mattes2024hieros\n  title: \"Hieros: Hierarchical Imagination on Structured State Space Sequence World Models\"\n  authors: [Mattes P., Schlosser R., Herbrich R.]\n  year: 2024\n  venue: ICML\n  category: direct-competitor\n  role: \"Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Seed-dependent instability & value overestimation in MBRL\n# ============================================================\n\n- paper_id: henderson2018deep\n  title: \"Deep Reinforcement Learning that Matters\"\n  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]\n  year: 2018\n  venue: AAAI\n  category: background\n  role: \"Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config\"\n  relevance_score: 4\n\n- paper_id: nikishin2022primacy\n  title: \"The Primacy Bias in Deep Reinforcement Learning\"\n  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]\n  year: 2022\n  venue: ICML\n  category: background\n  role: \"Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent\"\n  relevance_score: 4\n\n- paper_id: qiao2023mind\n  title: \"Mind the Model, Not the Agent: The Primacy Bias in Model-based RL\"\n  authors: [Qiao Z., Lyu J., Li X.]\n  year: 2023\n  venue: \"arXiv:2310.15017 (ECAI 2024)\"\n  category: evaluation\n  role: \"Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't\"\n  relevance_score: 5\n\n- paper_id: hussing2024dissecting\n  title: \"Dissecting Deep RL with High Update Ratios: Combatting Value Divergence\"\n  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]\n  year: 2024\n  venue: \"Reinforcement Learning Journal (RLC 2024)\"\n  category: evaluation\n  role: \"Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization\"\n  relevance_score: 4\n\n- paper_id: barkley2024stealing\n  title: \"Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning\"\n  authors: [Barkley B., Fridovich-Keil D.]\n  year: 2024\n  venue: \"arXiv:2412.14312 (ICML 2025)\"\n  category: evaluation\n  role: \"Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix\"\n  relevance_score: 3\n\n- paper_id: bjorck2022variance\n  title: \"Is High Variance Unavoidable in RL? A Case Study in Continuous Control\"\n  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]\n  year: 2022\n  venue: ICLR\n  category: background\n  role: \"Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Reward prediction quality → MBRL performance\n# ============================================================\n# Our key finding: removing dt_embedding causes reward_MAE to spike 75x\n# (0.01 → 0.747), making performance seed-dependent. These papers\n# establish that reward prediction quality is a known MBRL bottleneck.\n\n- paper_id: lee2024dreamsmooth\n  title: \"DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing\"\n  authors: [Lee V., Abbeel P., Lee Y.]\n  year: 2024\n  venue: ICLR\n  category: background\n  role: \"Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x\"\n  relevance_score: 5\n\n- paper_id: ma2024harmonydream\n  title: \"HarmonyDream: Task Harmonization Inside World Models\"\n  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]\n  year: 2024\n  venue: ICML\n  category: background\n  role: \"Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion\"\n  relevance_score: 5\n\n- paper_id: lambert2020objective\n  title: \"Objective Mismatch in Model-based Reinforcement Learning\"\n  authors: [Lambert N., Amos B., Yadan O., Calandra R.]\n  year: 2020\n  venue: \"L4DC (Proceedings of Machine Learning Research, vol. 120)\"\n  category: background\n  role: \"Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Auxiliary tasks & representation coupling in world models\n# ============================================================\n# Our finding: reward prediction quality is tightly coupled to temporal\n# conditioning (dt_embedding). Removing the embedding degrades the\n# reward head while dynamics remain intact — suggesting the reward head\n# acts as more than a passive predictor; it conditions the shared\n# representation. Literature gap: no prior work studies this coupling\n# specifically in Dreamer-family world models.\n\n- paper_id: jaderberg2017unreal\n  title: \"Reinforcement Learning with Unsupervised Auxiliary Tasks\"\n  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]\n  year: 2017\n  venue: ICLR\n  category: background\n  role: \"UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction\"\n  relevance_score: 4\n\n- paper_id: lyle2021auxiliary\n  title: \"On The Effect of Auxiliary Tasks on Representation Dynamics\"\n  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]\n  year: 2021\n  venue: AISTATS\n  category: background\n  role: \"Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV3 architecture improvements (2025-2026)\n# ============================================================\n\n- paper_id: bredis2026nedreamer\n  title: \"Next Embedding Prediction Makes World Models Stronger\"\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\n  year: 2026\n  venue: \"arXiv:2603.02765\"\n  category: direct-competitor\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"\n  relevance_score: 3\n\n- paper_id: zhang2025dymodreamer\n  title: \"DyMoDreamer: World Modeling with Dynamic Modulation\"\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\n  year: 2025\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Temporal abstraction methods\n# ============================================================\n\n- paper_id: liu2025vanta\n  title: \"Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning\"\n  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]\n  year: 2025\n  venue: ICLR\n  category: method-component\n  role: \"VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Evaluation methodology\n# ============================================================\n\n- paper_id: agarwal2021precipice\n  title: \"Deep Reinforcement Learning at the Edge of the Statistical Precipice\"\n  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]\n  year: 2021\n  venue: NeurIPS\n  category: evaluation\n  role: \"Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds\"\n  relevance_score: 4\n",
    "structuredPatch": [
      {
        "oldStart": 250,
        "oldLines": 7,
        "newStart": 250,
        "newLines": 7,
        "lines": [
          "   authors: [Micheli V., Alonso E., Fleuret F.]",
          "   year: 2023",
          "   venue: ICLR",
          "-  category: direct-competitor",
          "+  category: background",
          "   role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"",
          "   relevance_score: 3",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 33_

<details open><summary>🔧 Tool call — Edit · `toolu_019R4iZknnsY64SeYxuxSQQb`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "  category: direct-competitor\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"",
  "new_string": "  category: background\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "e0c6de88-e3e6-47de-8cd5-2b277ad26dd2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BwgraSDAtZjh6JQnUjmhuw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7658,
      "cache_read_input_tokens": 37973,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7658
      },
      "output_tokens": 10,
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

_source line 34 · 2026-05-14T14:57:51.759Z_

<details><summary>↩ Tool result · `toolu_019R4iZknnsY64SeYxuxSQQb`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "9bf5266a-fad7-4e3a-8d22-6c27150290ad",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
    "oldString": "  category: direct-competitor\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"",
    "newString": "  category: background\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"",
    "originalFile": "# Literature Map — event-gated-adaptive-horizon\n# Last updated: 2026-05-14\n# Total: 43 papers (5 existing + 38 new)\n\n# ============================================================\n# EXISTING CITATIONS (already in paper.tex)\n# ============================================================\n\n- paper_id: sutton1999options\n  title: \"Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning\"\n  authors: [Sutton R.S., Precup D., Singh S.]\n  year: 1999\n  venue: \"Artificial Intelligence 112(1-2):181-211\"\n  category: background\n  role: \"Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL\"\n  relevance_score: 5\n\n- paper_id: hafner2020dreamerv1\n  title: \"Dream to Control: Learning Behaviors by Latent Imagination\"\n  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]\n  year: 2020\n  venue: ICLR\n  category: background\n  role: \"DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm\"\n  relevance_score: 5\n\n- paper_id: hafner2023dreamerv3\n  title: \"Mastering Diverse Domains through World Models\"\n  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]\n  year: 2023\n  venue: \"arXiv:2301.04104 (Nature 2025)\"\n  category: background\n  role: \"DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here\"\n  relevance_score: 5\n\n- paper_id: sharma2017figar\n  title: \"Fine Grained Action Repetition for Deep Reinforcement Learning\"\n  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]\n  year: 2017\n  venue: \"ICLR Workshop\"\n  category: method-component\n  role: \"FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL\"\n  relevance_score: 4\n\n- paper_id: janner2019mbpo\n  title: \"When to Trust Your Model: Model-Based Policy Optimization\"\n  authors: [Janner M., Fu J., Zhang M., Levine S.]\n  year: 2019\n  venue: NeurIPS\n  category: background\n  role: \"MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Multi-step prediction error compounding\n# ============================================================\n\n- paper_id: ke2019learning\n  title: \"Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future\"\n  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]\n  year: 2019\n  venue: ICLR\n  category: background\n  role: \"Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1\"\n  relevance_score: 4\n\n- paper_id: asadi2019combating\n  title: \"Combating the Compounding-Error Problem with a Multi-step Model\"\n  authors: [Asadi K., Misra D., Kim S., Littman M.L.]\n  year: 2019\n  venue: \"arXiv:1905.13320\"\n  category: background\n  role: \"Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error\"\n  relevance_score: 4\n\n- paper_id: venkatraman2015improving\n  title: \"Improving Multi-Step Prediction of Learned Time Series Models\"\n  authors: [Venkatraman A., Hebert M., Bagnell J.A.]\n  year: 2015\n  venue: AAAI\n  category: background\n  role: \"Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error\"\n  relevance_score: 3\n\n- paper_id: lambert2022investigating\n  title: \"Investigating Compounding Prediction Errors in Learned Dynamics Models\"\n  authors: [Lambert N., Pister K.S.J., Calandra R.]\n  year: 2022\n  venue: \"arXiv:2203.09637\"\n  category: background\n  role: \"Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Model-predictive control with learned dynamics\n# ============================================================\n\n- paper_id: chua2018pets\n  title: \"Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models\"\n  authors: [Chua K., Calandra R., McAllister R., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach\"\n  relevance_score: 3\n\n- paper_id: nagabandi2018neural\n  title: \"Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning\"\n  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]\n  year: 2018\n  venue: ICRA\n  category: background\n  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================\n\n- paper_id: thrun1993issues\n  title: \"Issues in Using Function Approximation for Reinforcement Learning\"\n  authors: [Thrun S., Schwartz A.]\n  year: 1993\n  venue: \"Connectionist Models Summer School\"\n  category: background\n  role: \"First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning\"\n  relevance_score: 4\n\n- paper_id: vanhasselt2016double\n  title: \"Deep Reinforcement Learning with Double Q-Learning\"\n  authors: [van Hasselt H., Guez A., Silver D.]\n  year: 2016\n  venue: AAAI\n  category: background\n  role: \"Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL\"\n  relevance_score: 4\n\n- paper_id: fujimoto2018td3\n  title: \"Addressing Function Approximation Error in Actor-Critic Methods\"\n  authors: [Fujimoto S., van Hoof H., Meger D.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify\"\n  relevance_score: 4\n\n- paper_id: haarnoja2018sac\n  title: \"Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor\"\n  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values\"\n  relevance_score: 3\n\n- paper_id: lee2021sunrise\n  title: \"SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning\"\n  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Delusional bias\n# ============================================================\n\n- paper_id: lu2018nondelusional\n  title: \"Non-delusional Q-learning and Value-Iteration\"\n  authors: [Lu T., Schuurmans D., Boutilier C.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Hierarchical RL with learned models\n# ============================================================\n\n- paper_id: hafner2022director\n  title: \"Deep Hierarchical Planning from Pixels\"\n  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]\n  year: 2022\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt\"\n  relevance_score: 4\n\n- paper_id: nachum2018hiro\n  title: \"Data-Efficient Hierarchical Reinforcement Learning\"\n  authors: [Nachum O., Gu S., Lee H., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Action repeat / frame skip\n# ============================================================\n\n- paper_id: braylan2015frame\n  title: \"Frame Skip Is a Powerful Parameter for Learning to Play Atari\"\n  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]\n  year: 2015\n  venue: \"AAAI Workshop on Learning for General Competency in Video Games\"\n  category: background\n  role: \"Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice\"\n  relevance_score: 3\n\n- paper_id: lakshminarayanan2017dynamic\n  title: \"Dynamic Action Repetition for Deep Reinforcement Learning\"\n  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]\n  year: 2017\n  venue: AAAI\n  category: method-component\n  role: \"Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach\"\n  relevance_score: 4\n\n- paper_id: biedenkapp2021temporl\n  title: \"TempoRL: Learning When to Act\"\n  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV2\n# ============================================================\n\n- paper_id: hafner2021dreamerv2\n  title: \"Mastering Atari with Discrete World Models\"\n  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]\n  year: 2021\n  venue: ICLR\n  category: background\n  role: \"DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Alternative world model architectures\n# ============================================================\n\n- paper_id: micheli2023iris\n  title: \"Transformers are Sample-Efficient World Models\"\n  authors: [Micheli V., Alonso E., Fleuret F.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"\n  relevance_score: 3\n\n- paper_id: robine2023twm\n  title: \"Transformer-based World Models Are Happy With 100k Interactions\"\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\n  year: 2023\n  venue: ICLR\n  category: direct-competitor\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"\n  relevance_score: 3\n\n- paper_id: chen2022transdreamer\n  title: \"TransDreamer: Reinforcement Learning with Transformer World Models\"\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\n  year: 2022\n  venue: \"arXiv:2202.09481\"\n  category: direct-competitor\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: 2024-2026 concurrent work on temporal abstraction in world models\n# ============================================================\n\n- paper_id: gumbsch2024thick\n  title: \"Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics\"\n  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]\n  year: 2024\n  venue: ICLR\n  category: direct-competitor\n  role: \"THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination\"\n  relevance_score: 5\n\n- paper_id: mattes2024hieros\n  title: \"Hieros: Hierarchical Imagination on Structured State Space Sequence World Models\"\n  authors: [Mattes P., Schlosser R., Herbrich R.]\n  year: 2024\n  venue: ICML\n  category: direct-competitor\n  role: \"Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Seed-dependent instability & value overestimation in MBRL\n# ============================================================\n\n- paper_id: henderson2018deep\n  title: \"Deep Reinforcement Learning that Matters\"\n  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]\n  year: 2018\n  venue: AAAI\n  category: background\n  role: \"Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config\"\n  relevance_score: 4\n\n- paper_id: nikishin2022primacy\n  title: \"The Primacy Bias in Deep Reinforcement Learning\"\n  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]\n  year: 2022\n  venue: ICML\n  category: background\n  role: \"Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent\"\n  relevance_score: 4\n\n- paper_id: qiao2023mind\n  title: \"Mind the Model, Not the Agent: The Primacy Bias in Model-based RL\"\n  authors: [Qiao Z., Lyu J., Li X.]\n  year: 2023\n  venue: \"arXiv:2310.15017 (ECAI 2024)\"\n  category: evaluation\n  role: \"Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't\"\n  relevance_score: 5\n\n- paper_id: hussing2024dissecting\n  title: \"Dissecting Deep RL with High Update Ratios: Combatting Value Divergence\"\n  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]\n  year: 2024\n  venue: \"Reinforcement Learning Journal (RLC 2024)\"\n  category: evaluation\n  role: \"Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization\"\n  relevance_score: 4\n\n- paper_id: barkley2024stealing\n  title: \"Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning\"\n  authors: [Barkley B., Fridovich-Keil D.]\n  year: 2024\n  venue: \"arXiv:2412.14312 (ICML 2025)\"\n  category: evaluation\n  role: \"Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix\"\n  relevance_score: 3\n\n- paper_id: bjorck2022variance\n  title: \"Is High Variance Unavoidable in RL? A Case Study in Continuous Control\"\n  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]\n  year: 2022\n  venue: ICLR\n  category: background\n  role: \"Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Reward prediction quality → MBRL performance\n# ============================================================\n# Our key finding: removing dt_embedding causes reward_MAE to spike 75x\n# (0.01 → 0.747), making performance seed-dependent. These papers\n# establish that reward prediction quality is a known MBRL bottleneck.\n\n- paper_id: lee2024dreamsmooth\n  title: \"DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing\"\n  authors: [Lee V., Abbeel P., Lee Y.]\n  year: 2024\n  venue: ICLR\n  category: background\n  role: \"Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x\"\n  relevance_score: 5\n\n- paper_id: ma2024harmonydream\n  title: \"HarmonyDream: Task Harmonization Inside World Models\"\n  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]\n  year: 2024\n  venue: ICML\n  category: background\n  role: \"Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion\"\n  relevance_score: 5\n\n- paper_id: lambert2020objective\n  title: \"Objective Mismatch in Model-based Reinforcement Learning\"\n  authors: [Lambert N., Amos B., Yadan O., Calandra R.]\n  year: 2020\n  venue: \"L4DC (Proceedings of Machine Learning Research, vol. 120)\"\n  category: background\n  role: \"Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Auxiliary tasks & representation coupling in world models\n# ============================================================\n# Our finding: reward prediction quality is tightly coupled to temporal\n# conditioning (dt_embedding). Removing the embedding degrades the\n# reward head while dynamics remain intact — suggesting the reward head\n# acts as more than a passive predictor; it conditions the shared\n# representation. Literature gap: no prior work studies this coupling\n# specifically in Dreamer-family world models.\n\n- paper_id: jaderberg2017unreal\n  title: \"Reinforcement Learning with Unsupervised Auxiliary Tasks\"\n  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]\n  year: 2017\n  venue: ICLR\n  category: background\n  role: \"UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction\"\n  relevance_score: 4\n\n- paper_id: lyle2021auxiliary\n  title: \"On The Effect of Auxiliary Tasks on Representation Dynamics\"\n  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]\n  year: 2021\n  venue: AISTATS\n  category: background\n  role: \"Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV3 architecture improvements (2025-2026)\n# ============================================================\n\n- paper_id: bredis2026nedreamer\n  title: \"Next Embedding Prediction Makes World Models Stronger\"\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\n  year: 2026\n  venue: \"arXiv:2603.02765\"\n  category: direct-competitor\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"\n  relevance_score: 3\n\n- paper_id: zhang2025dymodreamer\n  title: \"DyMoDreamer: World Modeling with Dynamic Modulation\"\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\n  year: 2025\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Temporal abstraction methods\n# ============================================================\n\n- paper_id: liu2025vanta\n  title: \"Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning\"\n  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]\n  year: 2025\n  venue: ICLR\n  category: method-component\n  role: \"VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Evaluation methodology\n# ============================================================\n\n- paper_id: agarwal2021precipice\n  title: \"Deep Reinforcement Learning at the Edge of the Statistical Precipice\"\n  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]\n  year: 2021\n  venue: NeurIPS\n  category: evaluation\n  role: \"Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds\"\n  relevance_score: 4\n",
    "structuredPatch": [
      {
        "oldStart": 259,
        "oldLines": 7,
        "newStart": 259,
        "newLines": 7,
        "lines": [
          "   authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]",
          "   year: 2023",
          "   venue: ICLR",
          "-  category: direct-competitor",
          "+  category: background",
          "   role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"",
          "   relevance_score: 3",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 35_

<details open><summary>🔧 Tool call — Edit · `toolu_01JuVabxtEsAQ3zr8haEshYv`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "  category: direct-competitor\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"",
  "new_string": "  category: background\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "647d430a-dc63-4d52-ae3d-09059db4dc21",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BwgraSDAtZjh6JQnUjmhuw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7658,
      "cache_read_input_tokens": 37973,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7658
      },
      "output_tokens": 10,
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

_source line 36 · 2026-05-14T14:57:53.203Z_

<details><summary>↩ Tool result · `toolu_01JuVabxtEsAQ3zr8haEshYv`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "baaa1b78-b8d8-4a43-961d-0bc3b522dce9",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
    "oldString": "  category: direct-competitor\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"",
    "newString": "  category: background\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"",
    "originalFile": "# Literature Map — event-gated-adaptive-horizon\n# Last updated: 2026-05-14\n# Total: 43 papers (5 existing + 38 new)\n\n# ============================================================\n# EXISTING CITATIONS (already in paper.tex)\n# ============================================================\n\n- paper_id: sutton1999options\n  title: \"Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning\"\n  authors: [Sutton R.S., Precup D., Singh S.]\n  year: 1999\n  venue: \"Artificial Intelligence 112(1-2):181-211\"\n  category: background\n  role: \"Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL\"\n  relevance_score: 5\n\n- paper_id: hafner2020dreamerv1\n  title: \"Dream to Control: Learning Behaviors by Latent Imagination\"\n  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]\n  year: 2020\n  venue: ICLR\n  category: background\n  role: \"DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm\"\n  relevance_score: 5\n\n- paper_id: hafner2023dreamerv3\n  title: \"Mastering Diverse Domains through World Models\"\n  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]\n  year: 2023\n  venue: \"arXiv:2301.04104 (Nature 2025)\"\n  category: background\n  role: \"DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here\"\n  relevance_score: 5\n\n- paper_id: sharma2017figar\n  title: \"Fine Grained Action Repetition for Deep Reinforcement Learning\"\n  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]\n  year: 2017\n  venue: \"ICLR Workshop\"\n  category: method-component\n  role: \"FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL\"\n  relevance_score: 4\n\n- paper_id: janner2019mbpo\n  title: \"When to Trust Your Model: Model-Based Policy Optimization\"\n  authors: [Janner M., Fu J., Zhang M., Levine S.]\n  year: 2019\n  venue: NeurIPS\n  category: background\n  role: \"MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Multi-step prediction error compounding\n# ============================================================\n\n- paper_id: ke2019learning\n  title: \"Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future\"\n  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]\n  year: 2019\n  venue: ICLR\n  category: background\n  role: \"Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1\"\n  relevance_score: 4\n\n- paper_id: asadi2019combating\n  title: \"Combating the Compounding-Error Problem with a Multi-step Model\"\n  authors: [Asadi K., Misra D., Kim S., Littman M.L.]\n  year: 2019\n  venue: \"arXiv:1905.13320\"\n  category: background\n  role: \"Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error\"\n  relevance_score: 4\n\n- paper_id: venkatraman2015improving\n  title: \"Improving Multi-Step Prediction of Learned Time Series Models\"\n  authors: [Venkatraman A., Hebert M., Bagnell J.A.]\n  year: 2015\n  venue: AAAI\n  category: background\n  role: \"Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error\"\n  relevance_score: 3\n\n- paper_id: lambert2022investigating\n  title: \"Investigating Compounding Prediction Errors in Learned Dynamics Models\"\n  authors: [Lambert N., Pister K.S.J., Calandra R.]\n  year: 2022\n  venue: \"arXiv:2203.09637\"\n  category: background\n  role: \"Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Model-predictive control with learned dynamics\n# ============================================================\n\n- paper_id: chua2018pets\n  title: \"Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models\"\n  authors: [Chua K., Calandra R., McAllister R., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach\"\n  relevance_score: 3\n\n- paper_id: nagabandi2018neural\n  title: \"Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning\"\n  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]\n  year: 2018\n  venue: ICRA\n  category: background\n  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================\n\n- paper_id: thrun1993issues\n  title: \"Issues in Using Function Approximation for Reinforcement Learning\"\n  authors: [Thrun S., Schwartz A.]\n  year: 1993\n  venue: \"Connectionist Models Summer School\"\n  category: background\n  role: \"First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning\"\n  relevance_score: 4\n\n- paper_id: vanhasselt2016double\n  title: \"Deep Reinforcement Learning with Double Q-Learning\"\n  authors: [van Hasselt H., Guez A., Silver D.]\n  year: 2016\n  venue: AAAI\n  category: background\n  role: \"Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL\"\n  relevance_score: 4\n\n- paper_id: fujimoto2018td3\n  title: \"Addressing Function Approximation Error in Actor-Critic Methods\"\n  authors: [Fujimoto S., van Hoof H., Meger D.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify\"\n  relevance_score: 4\n\n- paper_id: haarnoja2018sac\n  title: \"Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor\"\n  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values\"\n  relevance_score: 3\n\n- paper_id: lee2021sunrise\n  title: \"SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning\"\n  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Delusional bias\n# ============================================================\n\n- paper_id: lu2018nondelusional\n  title: \"Non-delusional Q-learning and Value-Iteration\"\n  authors: [Lu T., Schuurmans D., Boutilier C.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Hierarchical RL with learned models\n# ============================================================\n\n- paper_id: hafner2022director\n  title: \"Deep Hierarchical Planning from Pixels\"\n  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]\n  year: 2022\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt\"\n  relevance_score: 4\n\n- paper_id: nachum2018hiro\n  title: \"Data-Efficient Hierarchical Reinforcement Learning\"\n  authors: [Nachum O., Gu S., Lee H., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Action repeat / frame skip\n# ============================================================\n\n- paper_id: braylan2015frame\n  title: \"Frame Skip Is a Powerful Parameter for Learning to Play Atari\"\n  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]\n  year: 2015\n  venue: \"AAAI Workshop on Learning for General Competency in Video Games\"\n  category: background\n  role: \"Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice\"\n  relevance_score: 3\n\n- paper_id: lakshminarayanan2017dynamic\n  title: \"Dynamic Action Repetition for Deep Reinforcement Learning\"\n  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]\n  year: 2017\n  venue: AAAI\n  category: method-component\n  role: \"Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach\"\n  relevance_score: 4\n\n- paper_id: biedenkapp2021temporl\n  title: \"TempoRL: Learning When to Act\"\n  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV2\n# ============================================================\n\n- paper_id: hafner2021dreamerv2\n  title: \"Mastering Atari with Discrete World Models\"\n  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]\n  year: 2021\n  venue: ICLR\n  category: background\n  role: \"DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Alternative world model architectures\n# ============================================================\n\n- paper_id: micheli2023iris\n  title: \"Transformers are Sample-Efficient World Models\"\n  authors: [Micheli V., Alonso E., Fleuret F.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"\n  relevance_score: 3\n\n- paper_id: robine2023twm\n  title: \"Transformer-based World Models Are Happy With 100k Interactions\"\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"\n  relevance_score: 3\n\n- paper_id: chen2022transdreamer\n  title: \"TransDreamer: Reinforcement Learning with Transformer World Models\"\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\n  year: 2022\n  venue: \"arXiv:2202.09481\"\n  category: direct-competitor\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: 2024-2026 concurrent work on temporal abstraction in world models\n# ============================================================\n\n- paper_id: gumbsch2024thick\n  title: \"Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics\"\n  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]\n  year: 2024\n  venue: ICLR\n  category: direct-competitor\n  role: \"THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination\"\n  relevance_score: 5\n\n- paper_id: mattes2024hieros\n  title: \"Hieros: Hierarchical Imagination on Structured State Space Sequence World Models\"\n  authors: [Mattes P., Schlosser R., Herbrich R.]\n  year: 2024\n  venue: ICML\n  category: direct-competitor\n  role: \"Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Seed-dependent instability & value overestimation in MBRL\n# ============================================================\n\n- paper_id: henderson2018deep\n  title: \"Deep Reinforcement Learning that Matters\"\n  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]\n  year: 2018\n  venue: AAAI\n  category: background\n  role: \"Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config\"\n  relevance_score: 4\n\n- paper_id: nikishin2022primacy\n  title: \"The Primacy Bias in Deep Reinforcement Learning\"\n  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]\n  year: 2022\n  venue: ICML\n  category: background\n  role: \"Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent\"\n  relevance_score: 4\n\n- paper_id: qiao2023mind\n  title: \"Mind the Model, Not the Agent: The Primacy Bias in Model-based RL\"\n  authors: [Qiao Z., Lyu J., Li X.]\n  year: 2023\n  venue: \"arXiv:2310.15017 (ECAI 2024)\"\n  category: evaluation\n  role: \"Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't\"\n  relevance_score: 5\n\n- paper_id: hussing2024dissecting\n  title: \"Dissecting Deep RL with High Update Ratios: Combatting Value Divergence\"\n  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]\n  year: 2024\n  venue: \"Reinforcement Learning Journal (RLC 2024)\"\n  category: evaluation\n  role: \"Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization\"\n  relevance_score: 4\n\n- paper_id: barkley2024stealing\n  title: \"Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning\"\n  authors: [Barkley B., Fridovich-Keil D.]\n  year: 2024\n  venue: \"arXiv:2412.14312 (ICML 2025)\"\n  category: evaluation\n  role: \"Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix\"\n  relevance_score: 3\n\n- paper_id: bjorck2022variance\n  title: \"Is High Variance Unavoidable in RL? A Case Study in Continuous Control\"\n  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]\n  year: 2022\n  venue: ICLR\n  category: background\n  role: \"Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Reward prediction quality → MBRL performance\n# ============================================================\n# Our key finding: removing dt_embedding causes reward_MAE to spike 75x\n# (0.01 → 0.747), making performance seed-dependent. These papers\n# establish that reward prediction quality is a known MBRL bottleneck.\n\n- paper_id: lee2024dreamsmooth\n  title: \"DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing\"\n  authors: [Lee V., Abbeel P., Lee Y.]\n  year: 2024\n  venue: ICLR\n  category: background\n  role: \"Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x\"\n  relevance_score: 5\n\n- paper_id: ma2024harmonydream\n  title: \"HarmonyDream: Task Harmonization Inside World Models\"\n  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]\n  year: 2024\n  venue: ICML\n  category: background\n  role: \"Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion\"\n  relevance_score: 5\n\n- paper_id: lambert2020objective\n  title: \"Objective Mismatch in Model-based Reinforcement Learning\"\n  authors: [Lambert N., Amos B., Yadan O., Calandra R.]\n  year: 2020\n  venue: \"L4DC (Proceedings of Machine Learning Research, vol. 120)\"\n  category: background\n  role: \"Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Auxiliary tasks & representation coupling in world models\n# ============================================================\n# Our finding: reward prediction quality is tightly coupled to temporal\n# conditioning (dt_embedding). Removing the embedding degrades the\n# reward head while dynamics remain intact — suggesting the reward head\n# acts as more than a passive predictor; it conditions the shared\n# representation. Literature gap: no prior work studies this coupling\n# specifically in Dreamer-family world models.\n\n- paper_id: jaderberg2017unreal\n  title: \"Reinforcement Learning with Unsupervised Auxiliary Tasks\"\n  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]\n  year: 2017\n  venue: ICLR\n  category: background\n  role: \"UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction\"\n  relevance_score: 4\n\n- paper_id: lyle2021auxiliary\n  title: \"On The Effect of Auxiliary Tasks on Representation Dynamics\"\n  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]\n  year: 2021\n  venue: AISTATS\n  category: background\n  role: \"Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV3 architecture improvements (2025-2026)\n# ============================================================\n\n- paper_id: bredis2026nedreamer\n  title: \"Next Embedding Prediction Makes World Models Stronger\"\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\n  year: 2026\n  venue: \"arXiv:2603.02765\"\n  category: direct-competitor\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"\n  relevance_score: 3\n\n- paper_id: zhang2025dymodreamer\n  title: \"DyMoDreamer: World Modeling with Dynamic Modulation\"\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\n  year: 2025\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Temporal abstraction methods\n# ============================================================\n\n- paper_id: liu2025vanta\n  title: \"Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning\"\n  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]\n  year: 2025\n  venue: ICLR\n  category: method-component\n  role: \"VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Evaluation methodology\n# ============================================================\n\n- paper_id: agarwal2021precipice\n  title: \"Deep Reinforcement Learning at the Edge of the Statistical Precipice\"\n  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]\n  year: 2021\n  venue: NeurIPS\n  category: evaluation\n  role: \"Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds\"\n  relevance_score: 4\n",
    "structuredPatch": [
      {
        "oldStart": 268,
        "oldLines": 7,
        "newStart": 268,
        "newLines": 7,
        "lines": [
          "   authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]",
          "   year: 2022",
          "   venue: \"arXiv:2202.09481\"",
          "-  category: direct-competitor",
          "+  category: background",
          "   role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"",
          "   relevance_score: 3",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 37_

<details open><summary>🔧 Tool call — Edit · `toolu_01JZ1mEbuKzQf8jXnCfXN1Mx`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "  category: direct-competitor\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"",
  "new_string": "  category: background\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "ea2730a7-9111-4665-abfe-f8278ba92767",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BwgraSDAtZjh6JQnUjmhuw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7658,
      "cache_read_input_tokens": 37973,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7658
      },
      "output_tokens": 10,
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

_source line 38 · 2026-05-14T14:57:55.023Z_

<details><summary>↩ Tool result · `toolu_01JZ1mEbuKzQf8jXnCfXN1Mx`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "7ab1e09d-f9d5-418d-8471-17ac30382548",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
    "oldString": "  category: direct-competitor\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"",
    "newString": "  category: background\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"",
    "originalFile": "# Literature Map — event-gated-adaptive-horizon\n# Last updated: 2026-05-14\n# Total: 43 papers (5 existing + 38 new)\n\n# ============================================================\n# EXISTING CITATIONS (already in paper.tex)\n# ============================================================\n\n- paper_id: sutton1999options\n  title: \"Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning\"\n  authors: [Sutton R.S., Precup D., Singh S.]\n  year: 1999\n  venue: \"Artificial Intelligence 112(1-2):181-211\"\n  category: background\n  role: \"Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL\"\n  relevance_score: 5\n\n- paper_id: hafner2020dreamerv1\n  title: \"Dream to Control: Learning Behaviors by Latent Imagination\"\n  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]\n  year: 2020\n  venue: ICLR\n  category: background\n  role: \"DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm\"\n  relevance_score: 5\n\n- paper_id: hafner2023dreamerv3\n  title: \"Mastering Diverse Domains through World Models\"\n  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]\n  year: 2023\n  venue: \"arXiv:2301.04104 (Nature 2025)\"\n  category: background\n  role: \"DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here\"\n  relevance_score: 5\n\n- paper_id: sharma2017figar\n  title: \"Fine Grained Action Repetition for Deep Reinforcement Learning\"\n  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]\n  year: 2017\n  venue: \"ICLR Workshop\"\n  category: method-component\n  role: \"FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL\"\n  relevance_score: 4\n\n- paper_id: janner2019mbpo\n  title: \"When to Trust Your Model: Model-Based Policy Optimization\"\n  authors: [Janner M., Fu J., Zhang M., Levine S.]\n  year: 2019\n  venue: NeurIPS\n  category: background\n  role: \"MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Multi-step prediction error compounding\n# ============================================================\n\n- paper_id: ke2019learning\n  title: \"Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future\"\n  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]\n  year: 2019\n  venue: ICLR\n  category: background\n  role: \"Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1\"\n  relevance_score: 4\n\n- paper_id: asadi2019combating\n  title: \"Combating the Compounding-Error Problem with a Multi-step Model\"\n  authors: [Asadi K., Misra D., Kim S., Littman M.L.]\n  year: 2019\n  venue: \"arXiv:1905.13320\"\n  category: background\n  role: \"Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error\"\n  relevance_score: 4\n\n- paper_id: venkatraman2015improving\n  title: \"Improving Multi-Step Prediction of Learned Time Series Models\"\n  authors: [Venkatraman A., Hebert M., Bagnell J.A.]\n  year: 2015\n  venue: AAAI\n  category: background\n  role: \"Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error\"\n  relevance_score: 3\n\n- paper_id: lambert2022investigating\n  title: \"Investigating Compounding Prediction Errors in Learned Dynamics Models\"\n  authors: [Lambert N., Pister K.S.J., Calandra R.]\n  year: 2022\n  venue: \"arXiv:2203.09637\"\n  category: background\n  role: \"Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Model-predictive control with learned dynamics\n# ============================================================\n\n- paper_id: chua2018pets\n  title: \"Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models\"\n  authors: [Chua K., Calandra R., McAllister R., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach\"\n  relevance_score: 3\n\n- paper_id: nagabandi2018neural\n  title: \"Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning\"\n  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]\n  year: 2018\n  venue: ICRA\n  category: background\n  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================\n\n- paper_id: thrun1993issues\n  title: \"Issues in Using Function Approximation for Reinforcement Learning\"\n  authors: [Thrun S., Schwartz A.]\n  year: 1993\n  venue: \"Connectionist Models Summer School\"\n  category: background\n  role: \"First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning\"\n  relevance_score: 4\n\n- paper_id: vanhasselt2016double\n  title: \"Deep Reinforcement Learning with Double Q-Learning\"\n  authors: [van Hasselt H., Guez A., Silver D.]\n  year: 2016\n  venue: AAAI\n  category: background\n  role: \"Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL\"\n  relevance_score: 4\n\n- paper_id: fujimoto2018td3\n  title: \"Addressing Function Approximation Error in Actor-Critic Methods\"\n  authors: [Fujimoto S., van Hoof H., Meger D.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify\"\n  relevance_score: 4\n\n- paper_id: haarnoja2018sac\n  title: \"Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor\"\n  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values\"\n  relevance_score: 3\n\n- paper_id: lee2021sunrise\n  title: \"SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning\"\n  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Delusional bias\n# ============================================================\n\n- paper_id: lu2018nondelusional\n  title: \"Non-delusional Q-learning and Value-Iteration\"\n  authors: [Lu T., Schuurmans D., Boutilier C.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Hierarchical RL with learned models\n# ============================================================\n\n- paper_id: hafner2022director\n  title: \"Deep Hierarchical Planning from Pixels\"\n  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]\n  year: 2022\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt\"\n  relevance_score: 4\n\n- paper_id: nachum2018hiro\n  title: \"Data-Efficient Hierarchical Reinforcement Learning\"\n  authors: [Nachum O., Gu S., Lee H., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Action repeat / frame skip\n# ============================================================\n\n- paper_id: braylan2015frame\n  title: \"Frame Skip Is a Powerful Parameter for Learning to Play Atari\"\n  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]\n  year: 2015\n  venue: \"AAAI Workshop on Learning for General Competency in Video Games\"\n  category: background\n  role: \"Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice\"\n  relevance_score: 3\n\n- paper_id: lakshminarayanan2017dynamic\n  title: \"Dynamic Action Repetition for Deep Reinforcement Learning\"\n  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]\n  year: 2017\n  venue: AAAI\n  category: method-component\n  role: \"Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach\"\n  relevance_score: 4\n\n- paper_id: biedenkapp2021temporl\n  title: \"TempoRL: Learning When to Act\"\n  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV2\n# ============================================================\n\n- paper_id: hafner2021dreamerv2\n  title: \"Mastering Atari with Discrete World Models\"\n  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]\n  year: 2021\n  venue: ICLR\n  category: background\n  role: \"DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Alternative world model architectures\n# ============================================================\n\n- paper_id: micheli2023iris\n  title: \"Transformers are Sample-Efficient World Models\"\n  authors: [Micheli V., Alonso E., Fleuret F.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"\n  relevance_score: 3\n\n- paper_id: robine2023twm\n  title: \"Transformer-based World Models Are Happy With 100k Interactions\"\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"\n  relevance_score: 3\n\n- paper_id: chen2022transdreamer\n  title: \"TransDreamer: Reinforcement Learning with Transformer World Models\"\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\n  year: 2022\n  venue: \"arXiv:2202.09481\"\n  category: background\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: 2024-2026 concurrent work on temporal abstraction in world models\n# ============================================================\n\n- paper_id: gumbsch2024thick\n  title: \"Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics\"\n  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]\n  year: 2024\n  venue: ICLR\n  category: direct-competitor\n  role: \"THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination\"\n  relevance_score: 5\n\n- paper_id: mattes2024hieros\n  title: \"Hieros: Hierarchical Imagination on Structured State Space Sequence World Models\"\n  authors: [Mattes P., Schlosser R., Herbrich R.]\n  year: 2024\n  venue: ICML\n  category: direct-competitor\n  role: \"Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Seed-dependent instability & value overestimation in MBRL\n# ============================================================\n\n- paper_id: henderson2018deep\n  title: \"Deep Reinforcement Learning that Matters\"\n  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]\n  year: 2018\n  venue: AAAI\n  category: background\n  role: \"Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config\"\n  relevance_score: 4\n\n- paper_id: nikishin2022primacy\n  title: \"The Primacy Bias in Deep Reinforcement Learning\"\n  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]\n  year: 2022\n  venue: ICML\n  category: background\n  role: \"Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent\"\n  relevance_score: 4\n\n- paper_id: qiao2023mind\n  title: \"Mind the Model, Not the Agent: The Primacy Bias in Model-based RL\"\n  authors: [Qiao Z., Lyu J., Li X.]\n  year: 2023\n  venue: \"arXiv:2310.15017 (ECAI 2024)\"\n  category: evaluation\n  role: \"Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't\"\n  relevance_score: 5\n\n- paper_id: hussing2024dissecting\n  title: \"Dissecting Deep RL with High Update Ratios: Combatting Value Divergence\"\n  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]\n  year: 2024\n  venue: \"Reinforcement Learning Journal (RLC 2024)\"\n  category: evaluation\n  role: \"Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization\"\n  relevance_score: 4\n\n- paper_id: barkley2024stealing\n  title: \"Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning\"\n  authors: [Barkley B., Fridovich-Keil D.]\n  year: 2024\n  venue: \"arXiv:2412.14312 (ICML 2025)\"\n  category: evaluation\n  role: \"Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix\"\n  relevance_score: 3\n\n- paper_id: bjorck2022variance\n  title: \"Is High Variance Unavoidable in RL? A Case Study in Continuous Control\"\n  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]\n  year: 2022\n  venue: ICLR\n  category: background\n  role: \"Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Reward prediction quality → MBRL performance\n# ============================================================\n# Our key finding: removing dt_embedding causes reward_MAE to spike 75x\n# (0.01 → 0.747), making performance seed-dependent. These papers\n# establish that reward prediction quality is a known MBRL bottleneck.\n\n- paper_id: lee2024dreamsmooth\n  title: \"DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing\"\n  authors: [Lee V., Abbeel P., Lee Y.]\n  year: 2024\n  venue: ICLR\n  category: background\n  role: \"Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x\"\n  relevance_score: 5\n\n- paper_id: ma2024harmonydream\n  title: \"HarmonyDream: Task Harmonization Inside World Models\"\n  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]\n  year: 2024\n  venue: ICML\n  category: background\n  role: \"Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion\"\n  relevance_score: 5\n\n- paper_id: lambert2020objective\n  title: \"Objective Mismatch in Model-based Reinforcement Learning\"\n  authors: [Lambert N., Amos B., Yadan O., Calandra R.]\n  year: 2020\n  venue: \"L4DC (Proceedings of Machine Learning Research, vol. 120)\"\n  category: background\n  role: \"Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Auxiliary tasks & representation coupling in world models\n# ============================================================\n# Our finding: reward prediction quality is tightly coupled to temporal\n# conditioning (dt_embedding). Removing the embedding degrades the\n# reward head while dynamics remain intact — suggesting the reward head\n# acts as more than a passive predictor; it conditions the shared\n# representation. Literature gap: no prior work studies this coupling\n# specifically in Dreamer-family world models.\n\n- paper_id: jaderberg2017unreal\n  title: \"Reinforcement Learning with Unsupervised Auxiliary Tasks\"\n  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]\n  year: 2017\n  venue: ICLR\n  category: background\n  role: \"UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction\"\n  relevance_score: 4\n\n- paper_id: lyle2021auxiliary\n  title: \"On The Effect of Auxiliary Tasks on Representation Dynamics\"\n  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]\n  year: 2021\n  venue: AISTATS\n  category: background\n  role: \"Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV3 architecture improvements (2025-2026)\n# ============================================================\n\n- paper_id: bredis2026nedreamer\n  title: \"Next Embedding Prediction Makes World Models Stronger\"\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\n  year: 2026\n  venue: \"arXiv:2603.02765\"\n  category: direct-competitor\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"\n  relevance_score: 3\n\n- paper_id: zhang2025dymodreamer\n  title: \"DyMoDreamer: World Modeling with Dynamic Modulation\"\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\n  year: 2025\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Temporal abstraction methods\n# ============================================================\n\n- paper_id: liu2025vanta\n  title: \"Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning\"\n  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]\n  year: 2025\n  venue: ICLR\n  category: method-component\n  role: \"VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Evaluation methodology\n# ============================================================\n\n- paper_id: agarwal2021precipice\n  title: \"Deep Reinforcement Learning at the Edge of the Statistical Precipice\"\n  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]\n  year: 2021\n  venue: NeurIPS\n  category: evaluation\n  role: \"Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds\"\n  relevance_score: 4\n",
    "structuredPatch": [
      {
        "oldStart": 423,
        "oldLines": 7,
        "newStart": 423,
        "newLines": 7,
        "lines": [
          "   authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]",
          "   year: 2026",
          "   venue: \"arXiv:2603.02765\"",
          "-  category: direct-competitor",
          "+  category: background",
          "   role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"",
          "   relevance_score: 3",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 39_

<details open><summary>🔧 Tool call — Edit · `toolu_012DyvinWZx8whVaW6Ehp32g`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "  category: direct-competitor\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"",
  "new_string": "  category: background\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "4fa830c5-f3f0-4041-a3ea-92f8d2a8ec6f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BwgraSDAtZjh6JQnUjmhuw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7658,
      "cache_read_input_tokens": 37973,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7658
      },
      "output_tokens": 10,
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

_source line 40 · 2026-05-14T14:57:57.507Z_

<details><summary>↩ Tool result · `toolu_012DyvinWZx8whVaW6Ehp32g`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "247d40bc-be25-47a7-87b2-8f66b8c2cbfe",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
    "oldString": "  category: direct-competitor\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"",
    "newString": "  category: background\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"",
    "originalFile": "# Literature Map — event-gated-adaptive-horizon\n# Last updated: 2026-05-14\n# Total: 43 papers (5 existing + 38 new)\n\n# ============================================================\n# EXISTING CITATIONS (already in paper.tex)\n# ============================================================\n\n- paper_id: sutton1999options\n  title: \"Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning\"\n  authors: [Sutton R.S., Precup D., Singh S.]\n  year: 1999\n  venue: \"Artificial Intelligence 112(1-2):181-211\"\n  category: background\n  role: \"Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL\"\n  relevance_score: 5\n\n- paper_id: hafner2020dreamerv1\n  title: \"Dream to Control: Learning Behaviors by Latent Imagination\"\n  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]\n  year: 2020\n  venue: ICLR\n  category: background\n  role: \"DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm\"\n  relevance_score: 5\n\n- paper_id: hafner2023dreamerv3\n  title: \"Mastering Diverse Domains through World Models\"\n  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]\n  year: 2023\n  venue: \"arXiv:2301.04104 (Nature 2025)\"\n  category: background\n  role: \"DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here\"\n  relevance_score: 5\n\n- paper_id: sharma2017figar\n  title: \"Fine Grained Action Repetition for Deep Reinforcement Learning\"\n  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]\n  year: 2017\n  venue: \"ICLR Workshop\"\n  category: method-component\n  role: \"FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL\"\n  relevance_score: 4\n\n- paper_id: janner2019mbpo\n  title: \"When to Trust Your Model: Model-Based Policy Optimization\"\n  authors: [Janner M., Fu J., Zhang M., Levine S.]\n  year: 2019\n  venue: NeurIPS\n  category: background\n  role: \"MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Multi-step prediction error compounding\n# ============================================================\n\n- paper_id: ke2019learning\n  title: \"Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future\"\n  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]\n  year: 2019\n  venue: ICLR\n  category: background\n  role: \"Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1\"\n  relevance_score: 4\n\n- paper_id: asadi2019combating\n  title: \"Combating the Compounding-Error Problem with a Multi-step Model\"\n  authors: [Asadi K., Misra D., Kim S., Littman M.L.]\n  year: 2019\n  venue: \"arXiv:1905.13320\"\n  category: background\n  role: \"Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error\"\n  relevance_score: 4\n\n- paper_id: venkatraman2015improving\n  title: \"Improving Multi-Step Prediction of Learned Time Series Models\"\n  authors: [Venkatraman A., Hebert M., Bagnell J.A.]\n  year: 2015\n  venue: AAAI\n  category: background\n  role: \"Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error\"\n  relevance_score: 3\n\n- paper_id: lambert2022investigating\n  title: \"Investigating Compounding Prediction Errors in Learned Dynamics Models\"\n  authors: [Lambert N., Pister K.S.J., Calandra R.]\n  year: 2022\n  venue: \"arXiv:2203.09637\"\n  category: background\n  role: \"Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Model-predictive control with learned dynamics\n# ============================================================\n\n- paper_id: chua2018pets\n  title: \"Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models\"\n  authors: [Chua K., Calandra R., McAllister R., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach\"\n  relevance_score: 3\n\n- paper_id: nagabandi2018neural\n  title: \"Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning\"\n  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]\n  year: 2018\n  venue: ICRA\n  category: background\n  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================\n\n- paper_id: thrun1993issues\n  title: \"Issues in Using Function Approximation for Reinforcement Learning\"\n  authors: [Thrun S., Schwartz A.]\n  year: 1993\n  venue: \"Connectionist Models Summer School\"\n  category: background\n  role: \"First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning\"\n  relevance_score: 4\n\n- paper_id: vanhasselt2016double\n  title: \"Deep Reinforcement Learning with Double Q-Learning\"\n  authors: [van Hasselt H., Guez A., Silver D.]\n  year: 2016\n  venue: AAAI\n  category: background\n  role: \"Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL\"\n  relevance_score: 4\n\n- paper_id: fujimoto2018td3\n  title: \"Addressing Function Approximation Error in Actor-Critic Methods\"\n  authors: [Fujimoto S., van Hoof H., Meger D.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify\"\n  relevance_score: 4\n\n- paper_id: haarnoja2018sac\n  title: \"Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor\"\n  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values\"\n  relevance_score: 3\n\n- paper_id: lee2021sunrise\n  title: \"SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning\"\n  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Delusional bias\n# ============================================================\n\n- paper_id: lu2018nondelusional\n  title: \"Non-delusional Q-learning and Value-Iteration\"\n  authors: [Lu T., Schuurmans D., Boutilier C.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Hierarchical RL with learned models\n# ============================================================\n\n- paper_id: hafner2022director\n  title: \"Deep Hierarchical Planning from Pixels\"\n  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]\n  year: 2022\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt\"\n  relevance_score: 4\n\n- paper_id: nachum2018hiro\n  title: \"Data-Efficient Hierarchical Reinforcement Learning\"\n  authors: [Nachum O., Gu S., Lee H., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Action repeat / frame skip\n# ============================================================\n\n- paper_id: braylan2015frame\n  title: \"Frame Skip Is a Powerful Parameter for Learning to Play Atari\"\n  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]\n  year: 2015\n  venue: \"AAAI Workshop on Learning for General Competency in Video Games\"\n  category: background\n  role: \"Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice\"\n  relevance_score: 3\n\n- paper_id: lakshminarayanan2017dynamic\n  title: \"Dynamic Action Repetition for Deep Reinforcement Learning\"\n  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]\n  year: 2017\n  venue: AAAI\n  category: method-component\n  role: \"Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach\"\n  relevance_score: 4\n\n- paper_id: biedenkapp2021temporl\n  title: \"TempoRL: Learning When to Act\"\n  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV2\n# ============================================================\n\n- paper_id: hafner2021dreamerv2\n  title: \"Mastering Atari with Discrete World Models\"\n  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]\n  year: 2021\n  venue: ICLR\n  category: background\n  role: \"DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Alternative world model architectures\n# ============================================================\n\n- paper_id: micheli2023iris\n  title: \"Transformers are Sample-Efficient World Models\"\n  authors: [Micheli V., Alonso E., Fleuret F.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"\n  relevance_score: 3\n\n- paper_id: robine2023twm\n  title: \"Transformer-based World Models Are Happy With 100k Interactions\"\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"\n  relevance_score: 3\n\n- paper_id: chen2022transdreamer\n  title: \"TransDreamer: Reinforcement Learning with Transformer World Models\"\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\n  year: 2022\n  venue: \"arXiv:2202.09481\"\n  category: background\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: 2024-2026 concurrent work on temporal abstraction in world models\n# ============================================================\n\n- paper_id: gumbsch2024thick\n  title: \"Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics\"\n  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]\n  year: 2024\n  venue: ICLR\n  category: direct-competitor\n  role: \"THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination\"\n  relevance_score: 5\n\n- paper_id: mattes2024hieros\n  title: \"Hieros: Hierarchical Imagination on Structured State Space Sequence World Models\"\n  authors: [Mattes P., Schlosser R., Herbrich R.]\n  year: 2024\n  venue: ICML\n  category: direct-competitor\n  role: \"Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Seed-dependent instability & value overestimation in MBRL\n# ============================================================\n\n- paper_id: henderson2018deep\n  title: \"Deep Reinforcement Learning that Matters\"\n  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]\n  year: 2018\n  venue: AAAI\n  category: background\n  role: \"Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config\"\n  relevance_score: 4\n\n- paper_id: nikishin2022primacy\n  title: \"The Primacy Bias in Deep Reinforcement Learning\"\n  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]\n  year: 2022\n  venue: ICML\n  category: background\n  role: \"Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent\"\n  relevance_score: 4\n\n- paper_id: qiao2023mind\n  title: \"Mind the Model, Not the Agent: The Primacy Bias in Model-based RL\"\n  authors: [Qiao Z., Lyu J., Li X.]\n  year: 2023\n  venue: \"arXiv:2310.15017 (ECAI 2024)\"\n  category: evaluation\n  role: \"Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't\"\n  relevance_score: 5\n\n- paper_id: hussing2024dissecting\n  title: \"Dissecting Deep RL with High Update Ratios: Combatting Value Divergence\"\n  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]\n  year: 2024\n  venue: \"Reinforcement Learning Journal (RLC 2024)\"\n  category: evaluation\n  role: \"Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization\"\n  relevance_score: 4\n\n- paper_id: barkley2024stealing\n  title: \"Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning\"\n  authors: [Barkley B., Fridovich-Keil D.]\n  year: 2024\n  venue: \"arXiv:2412.14312 (ICML 2025)\"\n  category: evaluation\n  role: \"Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix\"\n  relevance_score: 3\n\n- paper_id: bjorck2022variance\n  title: \"Is High Variance Unavoidable in RL? A Case Study in Continuous Control\"\n  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]\n  year: 2022\n  venue: ICLR\n  category: background\n  role: \"Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Reward prediction quality → MBRL performance\n# ============================================================\n# Our key finding: removing dt_embedding causes reward_MAE to spike 75x\n# (0.01 → 0.747), making performance seed-dependent. These papers\n# establish that reward prediction quality is a known MBRL bottleneck.\n\n- paper_id: lee2024dreamsmooth\n  title: \"DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing\"\n  authors: [Lee V., Abbeel P., Lee Y.]\n  year: 2024\n  venue: ICLR\n  category: background\n  role: \"Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x\"\n  relevance_score: 5\n\n- paper_id: ma2024harmonydream\n  title: \"HarmonyDream: Task Harmonization Inside World Models\"\n  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]\n  year: 2024\n  venue: ICML\n  category: background\n  role: \"Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion\"\n  relevance_score: 5\n\n- paper_id: lambert2020objective\n  title: \"Objective Mismatch in Model-based Reinforcement Learning\"\n  authors: [Lambert N., Amos B., Yadan O., Calandra R.]\n  year: 2020\n  venue: \"L4DC (Proceedings of Machine Learning Research, vol. 120)\"\n  category: background\n  role: \"Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Auxiliary tasks & representation coupling in world models\n# ============================================================\n# Our finding: reward prediction quality is tightly coupled to temporal\n# conditioning (dt_embedding). Removing the embedding degrades the\n# reward head while dynamics remain intact — suggesting the reward head\n# acts as more than a passive predictor; it conditions the shared\n# representation. Literature gap: no prior work studies this coupling\n# specifically in Dreamer-family world models.\n\n- paper_id: jaderberg2017unreal\n  title: \"Reinforcement Learning with Unsupervised Auxiliary Tasks\"\n  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]\n  year: 2017\n  venue: ICLR\n  category: background\n  role: \"UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction\"\n  relevance_score: 4\n\n- paper_id: lyle2021auxiliary\n  title: \"On The Effect of Auxiliary Tasks on Representation Dynamics\"\n  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]\n  year: 2021\n  venue: AISTATS\n  category: background\n  role: \"Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV3 architecture improvements (2025-2026)\n# ============================================================\n\n- paper_id: bredis2026nedreamer\n  title: \"Next Embedding Prediction Makes World Models Stronger\"\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\n  year: 2026\n  venue: \"arXiv:2603.02765\"\n  category: background\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"\n  relevance_score: 3\n\n- paper_id: zhang2025dymodreamer\n  title: \"DyMoDreamer: World Modeling with Dynamic Modulation\"\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\n  year: 2025\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Temporal abstraction methods\n# ============================================================\n\n- paper_id: liu2025vanta\n  title: \"Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning\"\n  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]\n  year: 2025\n  venue: ICLR\n  category: method-component\n  role: \"VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Evaluation methodology\n# ============================================================\n\n- paper_id: agarwal2021precipice\n  title: \"Deep Reinforcement Learning at the Edge of the Statistical Precipice\"\n  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]\n  year: 2021\n  venue: NeurIPS\n  category: evaluation\n  role: \"Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds\"\n  relevance_score: 4\n",
    "structuredPatch": [
      {
        "oldStart": 432,
        "oldLines": 7,
        "newStart": 432,
        "newLines": 7,
        "lines": [
          "   authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]",
          "   year: 2025",
          "   venue: NeurIPS",
          "-  category: direct-competitor",
          "+  category: background",
          "   role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"",
          "   relevance_score: 3",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 41_

<details open><summary>🔧 Tool call — Edit · `toolu_01CRfVN7ipbUbWve2Dz4e7vX`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================",
  "new_string": "  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n- paper_id: hansen2024tdmpc2\n  title: \"TD-MPC2: Scalable, Robust World Models for Continuous Control\"\n  authors: [Hansen N., Su H., Wang X.]\n  year: 2024\n  venue: \"ICLR (arXiv:2310.16828)\"\n  category: background\n  role: \"TD-MPC2 — SOTA MPC planning route (online planning + learned dynamics); DMC benchmark leader but orthogonal to imagination-based training — reviewer defense: TD-MPC2 does online MPC rollouts at test time, we study actor-critic training via imagined rollouts (DreamerV3 paradigm), not a same-level comparison\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Pessimistic MBRL / model exploitation mitigation\n# ============================================================\n\n- paper_id: yu2020mopo\n  title: \"MOPO: Model-based Offline Policy Optimization\"\n  authors: [Yu T., Thomas G., Yu L., Ermon S., Zou J., Levine S., Finn C., Ma T.]\n  year: 2020\n  venue: \"NeurIPS (arXiv:2005.13239)\"\n  category: background\n  role: \"MOPO — pessimistic MBRL via uncertainty-penalized reward (reward -= λ * model_uncertainty); generic model exploitation mitigation — reviewer defense: MOPO addresses distribution shift in offline MBRL, our dt=1 imagination restriction targets dt_embedding-induced delusional critic (temporal conditioning corruption), two complementary mechanisms\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "817c7019-d7e5-46f3-a559-2542e081d053",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BwgraSDAtZjh6JQnUjmhuw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7658,
      "cache_read_input_tokens": 37973,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7658
      },
      "output_tokens": 10,
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

_source line 42 · 2026-05-14T14:58:08.620Z_

<details><summary>↩ Tool result · `toolu_01CRfVN7ipbUbWve2Dz4e7vX`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "accd23c2-4e83-4840-9129-d2faeaf4c68e",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
    "oldString": "  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================",
    "newString": "  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n- paper_id: hansen2024tdmpc2\n  title: \"TD-MPC2: Scalable, Robust World Models for Continuous Control\"\n  authors: [Hansen N., Su H., Wang X.]\n  year: 2024\n  venue: \"ICLR (arXiv:2310.16828)\"\n  category: background\n  role: \"TD-MPC2 — SOTA MPC planning route (online planning + learned dynamics); DMC benchmark leader but orthogonal to imagination-based training — reviewer defense: TD-MPC2 does online MPC rollouts at test time, we study actor-critic training via imagined rollouts (DreamerV3 paradigm), not a same-level comparison\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Pessimistic MBRL / model exploitation mitigation\n# ============================================================\n\n- paper_id: yu2020mopo\n  title: \"MOPO: Model-based Offline Policy Optimization\"\n  authors: [Yu T., Thomas G., Yu L., Ermon S., Zou J., Levine S., Finn C., Ma T.]\n  year: 2020\n  venue: \"NeurIPS (arXiv:2005.13239)\"\n  category: background\n  role: \"MOPO — pessimistic MBRL via uncertainty-penalized reward (reward -= λ * model_uncertainty); generic model exploitation mitigation — reviewer defense: MOPO addresses distribution shift in offline MBRL, our dt=1 imagination restriction targets dt_embedding-induced delusional critic (temporal conditioning corruption), two complementary mechanisms\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================",
    "originalFile": "# Literature Map — event-gated-adaptive-horizon\n# Last updated: 2026-05-14\n# Total: 43 papers (5 existing + 38 new)\n\n# ============================================================\n# EXISTING CITATIONS (already in paper.tex)\n# ============================================================\n\n- paper_id: sutton1999options\n  title: \"Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning\"\n  authors: [Sutton R.S., Precup D., Singh S.]\n  year: 1999\n  venue: \"Artificial Intelligence 112(1-2):181-211\"\n  category: background\n  role: \"Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL\"\n  relevance_score: 5\n\n- paper_id: hafner2020dreamerv1\n  title: \"Dream to Control: Learning Behaviors by Latent Imagination\"\n  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]\n  year: 2020\n  venue: ICLR\n  category: background\n  role: \"DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm\"\n  relevance_score: 5\n\n- paper_id: hafner2023dreamerv3\n  title: \"Mastering Diverse Domains through World Models\"\n  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]\n  year: 2023\n  venue: \"arXiv:2301.04104 (Nature 2025)\"\n  category: background\n  role: \"DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here\"\n  relevance_score: 5\n\n- paper_id: sharma2017figar\n  title: \"Fine Grained Action Repetition for Deep Reinforcement Learning\"\n  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]\n  year: 2017\n  venue: \"ICLR Workshop\"\n  category: method-component\n  role: \"FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL\"\n  relevance_score: 4\n\n- paper_id: janner2019mbpo\n  title: \"When to Trust Your Model: Model-Based Policy Optimization\"\n  authors: [Janner M., Fu J., Zhang M., Levine S.]\n  year: 2019\n  venue: NeurIPS\n  category: background\n  role: \"MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Multi-step prediction error compounding\n# ============================================================\n\n- paper_id: ke2019learning\n  title: \"Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future\"\n  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]\n  year: 2019\n  venue: ICLR\n  category: background\n  role: \"Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1\"\n  relevance_score: 4\n\n- paper_id: asadi2019combating\n  title: \"Combating the Compounding-Error Problem with a Multi-step Model\"\n  authors: [Asadi K., Misra D., Kim S., Littman M.L.]\n  year: 2019\n  venue: \"arXiv:1905.13320\"\n  category: background\n  role: \"Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error\"\n  relevance_score: 4\n\n- paper_id: venkatraman2015improving\n  title: \"Improving Multi-Step Prediction of Learned Time Series Models\"\n  authors: [Venkatraman A., Hebert M., Bagnell J.A.]\n  year: 2015\n  venue: AAAI\n  category: background\n  role: \"Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error\"\n  relevance_score: 3\n\n- paper_id: lambert2022investigating\n  title: \"Investigating Compounding Prediction Errors in Learned Dynamics Models\"\n  authors: [Lambert N., Pister K.S.J., Calandra R.]\n  year: 2022\n  venue: \"arXiv:2203.09637\"\n  category: background\n  role: \"Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Model-predictive control with learned dynamics\n# ============================================================\n\n- paper_id: chua2018pets\n  title: \"Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models\"\n  authors: [Chua K., Calandra R., McAllister R., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach\"\n  relevance_score: 3\n\n- paper_id: nagabandi2018neural\n  title: \"Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning\"\n  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]\n  year: 2018\n  venue: ICRA\n  category: background\n  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================\n\n- paper_id: thrun1993issues\n  title: \"Issues in Using Function Approximation for Reinforcement Learning\"\n  authors: [Thrun S., Schwartz A.]\n  year: 1993\n  venue: \"Connectionist Models Summer School\"\n  category: background\n  role: \"First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning\"\n  relevance_score: 4\n\n- paper_id: vanhasselt2016double\n  title: \"Deep Reinforcement Learning with Double Q-Learning\"\n  authors: [van Hasselt H., Guez A., Silver D.]\n  year: 2016\n  venue: AAAI\n  category: background\n  role: \"Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL\"\n  relevance_score: 4\n\n- paper_id: fujimoto2018td3\n  title: \"Addressing Function Approximation Error in Actor-Critic Methods\"\n  authors: [Fujimoto S., van Hoof H., Meger D.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify\"\n  relevance_score: 4\n\n- paper_id: haarnoja2018sac\n  title: \"Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor\"\n  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values\"\n  relevance_score: 3\n\n- paper_id: lee2021sunrise\n  title: \"SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning\"\n  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Delusional bias\n# ============================================================\n\n- paper_id: lu2018nondelusional\n  title: \"Non-delusional Q-learning and Value-Iteration\"\n  authors: [Lu T., Schuurmans D., Boutilier C.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Hierarchical RL with learned models\n# ============================================================\n\n- paper_id: hafner2022director\n  title: \"Deep Hierarchical Planning from Pixels\"\n  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]\n  year: 2022\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt\"\n  relevance_score: 4\n\n- paper_id: nachum2018hiro\n  title: \"Data-Efficient Hierarchical Reinforcement Learning\"\n  authors: [Nachum O., Gu S., Lee H., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Action repeat / frame skip\n# ============================================================\n\n- paper_id: braylan2015frame\n  title: \"Frame Skip Is a Powerful Parameter for Learning to Play Atari\"\n  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]\n  year: 2015\n  venue: \"AAAI Workshop on Learning for General Competency in Video Games\"\n  category: background\n  role: \"Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice\"\n  relevance_score: 3\n\n- paper_id: lakshminarayanan2017dynamic\n  title: \"Dynamic Action Repetition for Deep Reinforcement Learning\"\n  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]\n  year: 2017\n  venue: AAAI\n  category: method-component\n  role: \"Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach\"\n  relevance_score: 4\n\n- paper_id: biedenkapp2021temporl\n  title: \"TempoRL: Learning When to Act\"\n  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV2\n# ============================================================\n\n- paper_id: hafner2021dreamerv2\n  title: \"Mastering Atari with Discrete World Models\"\n  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]\n  year: 2021\n  venue: ICLR\n  category: background\n  role: \"DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Alternative world model architectures\n# ============================================================\n\n- paper_id: micheli2023iris\n  title: \"Transformers are Sample-Efficient World Models\"\n  authors: [Micheli V., Alonso E., Fleuret F.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"\n  relevance_score: 3\n\n- paper_id: robine2023twm\n  title: \"Transformer-based World Models Are Happy With 100k Interactions\"\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"\n  relevance_score: 3\n\n- paper_id: chen2022transdreamer\n  title: \"TransDreamer: Reinforcement Learning with Transformer World Models\"\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\n  year: 2022\n  venue: \"arXiv:2202.09481\"\n  category: background\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: 2024-2026 concurrent work on temporal abstraction in world models\n# ============================================================\n\n- paper_id: gumbsch2024thick\n  title: \"Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics\"\n  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]\n  year: 2024\n  venue: ICLR\n  category: direct-competitor\n  role: \"THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination\"\n  relevance_score: 5\n\n- paper_id: mattes2024hieros\n  title: \"Hieros: Hierarchical Imagination on Structured State Space Sequence World Models\"\n  authors: [Mattes P., Schlosser R., Herbrich R.]\n  year: 2024\n  venue: ICML\n  category: direct-competitor\n  role: \"Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Seed-dependent instability & value overestimation in MBRL\n# ============================================================\n\n- paper_id: henderson2018deep\n  title: \"Deep Reinforcement Learning that Matters\"\n  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]\n  year: 2018\n  venue: AAAI\n  category: background\n  role: \"Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config\"\n  relevance_score: 4\n\n- paper_id: nikishin2022primacy\n  title: \"The Primacy Bias in Deep Reinforcement Learning\"\n  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]\n  year: 2022\n  venue: ICML\n  category: background\n  role: \"Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent\"\n  relevance_score: 4\n\n- paper_id: qiao2023mind\n  title: \"Mind the Model, Not the Agent: The Primacy Bias in Model-based RL\"\n  authors: [Qiao Z., Lyu J., Li X.]\n  year: 2023\n  venue: \"arXiv:2310.15017 (ECAI 2024)\"\n  category: evaluation\n  role: \"Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't\"\n  relevance_score: 5\n\n- paper_id: hussing2024dissecting\n  title: \"Dissecting Deep RL with High Update Ratios: Combatting Value Divergence\"\n  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]\n  year: 2024\n  venue: \"Reinforcement Learning Journal (RLC 2024)\"\n  category: evaluation\n  role: \"Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization\"\n  relevance_score: 4\n\n- paper_id: barkley2024stealing\n  title: \"Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning\"\n  authors: [Barkley B., Fridovich-Keil D.]\n  year: 2024\n  venue: \"arXiv:2412.14312 (ICML 2025)\"\n  category: evaluation\n  role: \"Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix\"\n  relevance_score: 3\n\n- paper_id: bjorck2022variance\n  title: \"Is High Variance Unavoidable in RL? A Case Study in Continuous Control\"\n  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]\n  year: 2022\n  venue: ICLR\n  category: background\n  role: \"Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Reward prediction quality → MBRL performance\n# ============================================================\n# Our key finding: removing dt_embedding causes reward_MAE to spike 75x\n# (0.01 → 0.747), making performance seed-dependent. These papers\n# establish that reward prediction quality is a known MBRL bottleneck.\n\n- paper_id: lee2024dreamsmooth\n  title: \"DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing\"\n  authors: [Lee V., Abbeel P., Lee Y.]\n  year: 2024\n  venue: ICLR\n  category: background\n  role: \"Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x\"\n  relevance_score: 5\n\n- paper_id: ma2024harmonydream\n  title: \"HarmonyDream: Task Harmonization Inside World Models\"\n  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]\n  year: 2024\n  venue: ICML\n  category: background\n  role: \"Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion\"\n  relevance_score: 5\n\n- paper_id: lambert2020objective\n  title: \"Objective Mismatch in Model-based Reinforcement Learning\"\n  authors: [Lambert N., Amos B., Yadan O., Calandra R.]\n  year: 2020\n  venue: \"L4DC (Proceedings of Machine Learning Research, vol. 120)\"\n  category: background\n  role: \"Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Auxiliary tasks & representation coupling in world models\n# ============================================================\n# Our finding: reward prediction quality is tightly coupled to temporal\n# conditioning (dt_embedding). Removing the embedding degrades the\n# reward head while dynamics remain intact — suggesting the reward head\n# acts as more than a passive predictor; it conditions the shared\n# representation. Literature gap: no prior work studies this coupling\n# specifically in Dreamer-family world models.\n\n- paper_id: jaderberg2017unreal\n  title: \"Reinforcement Learning with Unsupervised Auxiliary Tasks\"\n  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]\n  year: 2017\n  venue: ICLR\n  category: background\n  role: \"UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction\"\n  relevance_score: 4\n\n- paper_id: lyle2021auxiliary\n  title: \"On The Effect of Auxiliary Tasks on Representation Dynamics\"\n  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]\n  year: 2021\n  venue: AISTATS\n  category: background\n  role: \"Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV3 architecture improvements (2025-2026)\n# ============================================================\n\n- paper_id: bredis2026nedreamer\n  title: \"Next Embedding Prediction Makes World Models Stronger\"\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\n  year: 2026\n  venue: \"arXiv:2603.02765\"\n  category: background\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"\n  relevance_score: 3\n\n- paper_id: zhang2025dymodreamer\n  title: \"DyMoDreamer: World Modeling with Dynamic Modulation\"\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\n  year: 2025\n  venue: NeurIPS\n  category: background\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Temporal abstraction methods\n# ============================================================\n\n- paper_id: liu2025vanta\n  title: \"Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning\"\n  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]\n  year: 2025\n  venue: ICLR\n  category: method-component\n  role: \"VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Evaluation methodology\n# ============================================================\n\n- paper_id: agarwal2021precipice\n  title: \"Deep Reinforcement Learning at the Edge of the Statistical Precipice\"\n  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]\n  year: 2021\n  venue: NeurIPS\n  category: evaluation\n  role: \"Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds\"\n  relevance_score: 4\n",
    "structuredPatch": [
      {
        "oldStart": 113,
        "oldLines": 7,
        "newStart": 113,
        "newLines": 29,
        "lines": [
          "   role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"",
          "   relevance_score: 3",
          " ",
          "+- paper_id: hansen2024tdmpc2",
          "+  title: \"TD-MPC2: Scalable, Robust World Models for Continuous Control\"",
          "+  authors: [Hansen N., Su H., Wang X.]",
          "+  year: 2024",
          "+  venue: \"ICLR (arXiv:2310.16828)\"",
          "+  category: background",
          "+  role: \"TD-MPC2 — SOTA MPC planning route (online planning + learned dynamics); DMC benchmark leader but orthogonal to imagination-based training — reviewer defense: TD-MPC2 does online MPC rollouts at test time, we study actor-critic training via imagined rollouts (DreamerV3 paradigm), not a same-level comparison\"",
          "+  relevance_score: 4",
          "+",
          " # ============================================================",
          "+# NEW: Pessimistic MBRL / model exploitation mitigation",
          "+# ============================================================",
          "+",
          "+- paper_id: yu2020mopo",
          "+  title: \"MOPO: Model-based Offline Policy Optimization\"",
          "+  authors: [Yu T., Thomas G., Yu L., Ermon S., Zou J., Levine S., Finn C., Ma T.]",
          "+  year: 2020",
          "+  venue: \"NeurIPS (arXiv:2005.13239)\"",
          "+  category: background",
          "+  role: \"MOPO — pessimistic MBRL via uncertainty-penalized reward (reward -= λ * model_uncertainty); generic model exploitation mitigation — reviewer defense: MOPO addresses distribution shift in offline MBRL, our dt=1 imagination restriction targets dt_embedding-induced delusional critic (temporal conditioning corruption), two complementary mechanisms\"",
          "+  relevance_score: 4",
          "+",
          "+# ============================================================",
          " # NEW: Value overestimation mitigation",
          " # ============================================================",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 43_

Now update the paper count in the header.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "f58fef38-6003-44aa-9e0e-4956eda2a2e8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018nuNtryJrCdExeEuS2Dq4m",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2559,
      "cache_read_input_tokens": 45631,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2559
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

### Tool call

_source line 44_

<details open><summary>🔧 Tool call — Edit · `toolu_01NZL98qoGNxTmTCJTZ4Xesm`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "old_string": "# Total: 43 papers (5 existing + 38 new)",
  "new_string": "# Total: 45 papers (5 existing + 40 new)"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "699135b6-f549-4bca-91d5-bcefaecaa3b8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018nuNtryJrCdExeEuS2Dq4m",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2559,
      "cache_read_input_tokens": 45631,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2559
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

### Tool result

_source line 45 · 2026-05-14T14:58:12.714Z_

<details><summary>↩ Tool result · `toolu_01NZL98qoGNxTmTCJTZ4Xesm`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "bf92d317-d650-4fa3-a4b6-e35e3d3012ba",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
    "oldString": "# Total: 43 papers (5 existing + 38 new)",
    "newString": "# Total: 45 papers (5 existing + 40 new)",
    "originalFile": "# Literature Map — event-gated-adaptive-horizon\n# Last updated: 2026-05-14\n# Total: 43 papers (5 existing + 38 new)\n\n# ============================================================\n# EXISTING CITATIONS (already in paper.tex)\n# ============================================================\n\n- paper_id: sutton1999options\n  title: \"Between MDPs and Semi-MDPs: A Framework for Temporal Abstraction in Reinforcement Learning\"\n  authors: [Sutton R.S., Precup D., Singh S.]\n  year: 1999\n  venue: \"Artificial Intelligence 112(1-2):181-211\"\n  category: background\n  role: \"Foundational options framework for temporal abstraction in RL; our work investigates why temporal abstraction fails in world-model RL\"\n  relevance_score: 5\n\n- paper_id: hafner2020dreamerv1\n  title: \"Dream to Control: Learning Behaviors by Latent Imagination\"\n  authors: [Hafner D., Lillicrap T., Ba J., Norouzi M.]\n  year: 2020\n  venue: ICLR\n  category: background\n  role: \"DreamerV1 — base architecture family; our experiments build on the RSSM and imagination-based training paradigm\"\n  relevance_score: 5\n\n- paper_id: hafner2023dreamerv3\n  title: \"Mastering Diverse Domains through World Models\"\n  authors: [Hafner D., Pasukonis J., Ba J., Lillicrap T.]\n  year: 2023\n  venue: \"arXiv:2301.04104 (Nature 2025)\"\n  category: background\n  role: \"DreamerV3 — the specific base system we modify; symlog transforms, discrete latents, all default hyperparameters come from here\"\n  relevance_score: 5\n\n- paper_id: sharma2017figar\n  title: \"Fine Grained Action Repetition for Deep Reinforcement Learning\"\n  authors: [Sharma S., Lakshminarayanan A.S., Ravindran B.]\n  year: 2017\n  venue: \"ICLR Workshop\"\n  category: method-component\n  role: \"FiGAR — learns action-repeat durations in model-free RL; we extend the idea to imagination step size in world-model RL\"\n  relevance_score: 4\n\n- paper_id: janner2019mbpo\n  title: \"When to Trust Your Model: Model-Based Policy Optimization\"\n  authors: [Janner M., Fu J., Zhang M., Levine S.]\n  year: 2019\n  venue: NeurIPS\n  category: background\n  role: \"MBPO — formalizes model exploitation in MBRL; our delusional critic is a specific instance of model exploitation tied to temporal embedding\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Multi-step prediction error compounding\n# ============================================================\n\n- paper_id: ke2019learning\n  title: \"Learning Dynamics Model in Reinforcement Learning by Incorporating the Long Term Future\"\n  authors: [Ke N.R., Singh A., Touati A., Goyal A., Bengio Y., Parikh D., Batra D.]\n  year: 2019\n  venue: ICLR\n  category: background\n  role: \"Addresses long-term dynamics prediction via latent-variable autoregressive model; directly relevant to our finding that multi-step RSSM predictions degrade with dt>1\"\n  relevance_score: 4\n\n- paper_id: asadi2019combating\n  title: \"Combating the Compounding-Error Problem with a Multi-step Model\"\n  authors: [Asadi K., Misra D., Kim S., Littman M.L.]\n  year: 2019\n  venue: \"arXiv:1905.13320\"\n  category: background\n  role: \"Proposes multi-step models to bypass compounding error; our work shows that even with multi-step imagination, the dt-embedding creates a different failure mode (value overestimation) distinct from compounding error\"\n  relevance_score: 4\n\n- paper_id: venkatraman2015improving\n  title: \"Improving Multi-Step Prediction of Learned Time Series Models\"\n  authors: [Venkatraman A., Hebert M., Bagnell J.A.]\n  year: 2015\n  venue: AAAI\n  category: background\n  role: \"Data-as-Demonstrator (DaD) for robust multi-step prediction; establishes theoretical guarantee relating training error to multi-step prediction error\"\n  relevance_score: 3\n\n- paper_id: lambert2022investigating\n  title: \"Investigating Compounding Prediction Errors in Learned Dynamics Models\"\n  authors: [Lambert N., Pister K.S.J., Calandra R.]\n  year: 2022\n  venue: \"arXiv:2203.09637\"\n  category: background\n  role: \"Empirical study of compounding error properties; we rule out compounding error as the primary failure mechanism (008c vs 008a comparison) and identify value overestimation instead\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Model-predictive control with learned dynamics\n# ============================================================\n\n- paper_id: chua2018pets\n  title: \"Deep Reinforcement Learning in a Handful of Trials using Probabilistic Dynamics Models\"\n  authors: [Chua K., Calandra R., McAllister R., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"PETS — ensemble-based uncertainty-aware MPC; uses explicit uncertainty quantification to avoid model exploitation, contrasting with DreamerV3's implicit approach\"\n  relevance_score: 3\n\n- paper_id: nagabandi2018neural\n  title: \"Neural Network Dynamics for Model-Based Deep Reinforcement Learning with Model-Free Fine-Tuning\"\n  authors: [Nagabandi A., Kahn G., Fearing R.S., Levine S.]\n  year: 2018\n  venue: ICRA\n  category: background\n  role: \"Demonstrates NN dynamics + MPC for locomotion; model errors accumulate over prediction horizon, motivating our investigation of horizon-dependent failures\"\n  relevance_score: 3\n\n- paper_id: hansen2024tdmpc2\n  title: \"TD-MPC2: Scalable, Robust World Models for Continuous Control\"\n  authors: [Hansen N., Su H., Wang X.]\n  year: 2024\n  venue: \"ICLR (arXiv:2310.16828)\"\n  category: background\n  role: \"TD-MPC2 — SOTA MPC planning route (online planning + learned dynamics); DMC benchmark leader but orthogonal to imagination-based training — reviewer defense: TD-MPC2 does online MPC rollouts at test time, we study actor-critic training via imagined rollouts (DreamerV3 paradigm), not a same-level comparison\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Pessimistic MBRL / model exploitation mitigation\n# ============================================================\n\n- paper_id: yu2020mopo\n  title: \"MOPO: Model-based Offline Policy Optimization\"\n  authors: [Yu T., Thomas G., Yu L., Ermon S., Zou J., Levine S., Finn C., Ma T.]\n  year: 2020\n  venue: \"NeurIPS (arXiv:2005.13239)\"\n  category: background\n  role: \"MOPO — pessimistic MBRL via uncertainty-penalized reward (reward -= λ * model_uncertainty); generic model exploitation mitigation — reviewer defense: MOPO addresses distribution shift in offline MBRL, our dt=1 imagination restriction targets dt_embedding-induced delusional critic (temporal conditioning corruption), two complementary mechanisms\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Value overestimation mitigation\n# ============================================================\n\n- paper_id: thrun1993issues\n  title: \"Issues in Using Function Approximation for Reinforcement Learning\"\n  authors: [Thrun S., Schwartz A.]\n  year: 1993\n  venue: \"Connectionist Models Summer School\"\n  category: background\n  role: \"First identification of systematic value overestimation from function approximation; our delusional critic extends this to model-based imagination with temporal conditioning\"\n  relevance_score: 4\n\n- paper_id: vanhasselt2016double\n  title: \"Deep Reinforcement Learning with Double Q-Learning\"\n  authors: [van Hasselt H., Guez A., Silver D.]\n  year: 2016\n  venue: AAAI\n  category: background\n  role: \"Double DQN — mitigates overestimation via double estimator; our finding that trained dt-embedding enables value exploitation is a complementary overestimation mechanism in MBRL\"\n  relevance_score: 4\n\n- paper_id: fujimoto2018td3\n  title: \"Addressing Function Approximation Error in Actor-Critic Methods\"\n  authors: [Fujimoto S., van Hoof H., Meger D.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"TD3 — clipped double-Q to limit overestimation in actor-critic; DreamerV3 uses a single critic, making it more vulnerable to the overestimation we identify\"\n  relevance_score: 4\n\n- paper_id: haarnoja2018sac\n  title: \"Soft Actor-Critic: Off-Policy Maximum Entropy Deep Reinforcement Learning with a Stochastic Actor\"\n  authors: [Haarnoja T., Zhou A., Abbeel P., Levine S.]\n  year: 2018\n  venue: ICML\n  category: method-component\n  role: \"SAC — entropy regularization implicitly mitigates overestimation; relevant contrast to DreamerV3's actor which can greedily exploit overestimated values\"\n  relevance_score: 3\n\n- paper_id: lee2021sunrise\n  title: \"SUNRISE: A Simple Unified Framework for Ensemble Learning in Deep Reinforcement Learning\"\n  authors: [Lee K., Laskin M., Srinivas A., Abbeel P.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Ensemble-based uncertainty weighting for value estimation; potential mitigation for our identified delusional critic mechanism\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Delusional bias\n# ============================================================\n\n- paper_id: lu2018nondelusional\n  title: \"Non-delusional Q-learning and Value-Iteration\"\n  authors: [Lu T., Schuurmans D., Boutilier C.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"Formalizes delusional bias from policy-class constraints in Q-learning; we identify an analogous phenomenon where temporal conditioning enables the critic to exploit model imprecision\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Hierarchical RL with learned models\n# ============================================================\n\n- paper_id: hafner2022director\n  title: \"Deep Hierarchical Planning from Pixels\"\n  authors: [Hafner D., Lee K.-H., Fischer I., Abbeel P.]\n  year: 2022\n  venue: NeurIPS\n  category: direct-competitor\n  role: \"Director — hierarchical planning in Dreamer latent space via subgoals; addresses temporal abstraction through goal hierarchy rather than variable dt\"\n  relevance_score: 4\n\n- paper_id: nachum2018hiro\n  title: \"Data-Efficient Hierarchical Reinforcement Learning\"\n  authors: [Nachum O., Gu S., Lee H., Levine S.]\n  year: 2018\n  venue: NeurIPS\n  category: background\n  role: \"HIRO — off-policy HRL with learned subgoals; demonstrates that hierarchical temporal abstraction can improve sample efficiency when properly designed\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Action repeat / frame skip\n# ============================================================\n\n- paper_id: braylan2015frame\n  title: \"Frame Skip Is a Powerful Parameter for Learning to Play Atari\"\n  authors: [Braylan A., Hollenbeck M., Meyerson E., Miikkulainen R.]\n  year: 2015\n  venue: \"AAAI Workshop on Learning for General Competency in Video Games\"\n  category: background\n  role: \"Empirical study showing frame skip strongly affects Atari performance; motivates investigation of temporal granularity as a critical design choice\"\n  relevance_score: 3\n\n- paper_id: lakshminarayanan2017dynamic\n  title: \"Dynamic Action Repetition for Deep Reinforcement Learning\"\n  authors: [Lakshminarayanan A.S., Sharma S., Ravindran B.]\n  year: 2017\n  venue: AAAI\n  category: method-component\n  role: \"Learns per-step action repetition duration; model-free analog of our variable-dt imagination approach\"\n  relevance_score: 4\n\n- paper_id: biedenkapp2021temporl\n  title: \"TempoRL: Learning When to Act\"\n  authors: [Biedenkapp A., Rajan R., Hutter F., Lindauer M.]\n  year: 2021\n  venue: ICML\n  category: method-component\n  role: \"Learns action persistence via skip-policy; demonstrates up to 10x speedup — but in model-free setting without the model exploitation risk we identify\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV2\n# ============================================================\n\n- paper_id: hafner2021dreamerv2\n  title: \"Mastering Atari with Discrete World Models\"\n  authors: [Hafner D., Lillicrap T., Norouzi M., Ba J.]\n  year: 2021\n  venue: ICLR\n  category: background\n  role: \"DreamerV2 — introduces discrete latent representations used in DreamerV3; key architectural predecessor to our base system\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Alternative world model architectures\n# ============================================================\n\n- paper_id: micheli2023iris\n  title: \"Transformers are Sample-Efficient World Models\"\n  authors: [Micheli V., Alonso E., Fleuret F.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"IRIS — autoregressive transformer world model; alternative to RSSM that may exhibit different compounding error characteristics under temporal abstraction\"\n  relevance_score: 3\n\n- paper_id: robine2023twm\n  title: \"Transformer-based World Models Are Happy With 100k Interactions\"\n  authors: [Robine J., Hoeftmann M., Uelwer T., Harmeling S.]\n  year: 2023\n  venue: ICLR\n  category: background\n  role: \"TWM — Transformer-XL world model with direct state access; circumvents RSSM's recurrent compression that exacerbates our identified prediction gap\"\n  relevance_score: 3\n\n- paper_id: chen2022transdreamer\n  title: \"TransDreamer: Reinforcement Learning with Transformer World Models\"\n  authors: [Chen C., Wu Y.-F., Yoon J., Ahn S.]\n  year: 2022\n  venue: \"arXiv:2202.09481\"\n  category: background\n  role: \"Replaces RSSM with Transformer State-Space Model; directly tests whether RSSM-specific architecture contributes to temporal abstraction failures\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: 2024-2026 concurrent work on temporal abstraction in world models\n# ============================================================\n\n- paper_id: gumbsch2024thick\n  title: \"Learning Hierarchical World Models with Adaptive Temporal Abstractions from Discrete Latent Dynamics\"\n  authors: [Gumbsch C., Sajid N., Martius G., Butz M.V.]\n  year: 2024\n  venue: ICLR\n  category: direct-competitor\n  role: \"THICK — learns adaptive temporal abstractions via context-change detection; closest concurrent work — addresses temporal abstraction in Dreamer but via hierarchy rather than variable-dt imagination\"\n  relevance_score: 5\n\n- paper_id: mattes2024hieros\n  title: \"Hieros: Hierarchical Imagination on Structured State Space Sequence World Models\"\n  authors: [Mattes P., Schlosser R., Herbrich R.]\n  year: 2024\n  venue: ICML\n  category: direct-competitor\n  role: \"Multi-scale hierarchical imagination with S5 world model; demonstrates temporal abstraction via hierarchy avoids the single-scale dt-embedding failure we identify\"\n  relevance_score: 5\n\n# ============================================================\n# NEW: Seed-dependent instability & value overestimation in MBRL\n# ============================================================\n\n- paper_id: henderson2018deep\n  title: \"Deep Reinforcement Learning that Matters\"\n  authors: [Henderson P., Islam R., Bachman P., Pineau J., Precup D., Meger D.]\n  year: 2018\n  venue: AAAI\n  category: background\n  role: \"Foundational study on seed variance in deep RL — shows statistically different performance distributions arise from random seeds alone with identical hyperparameters; directly supports our observation that seed 0 vs seed 2 produce qualitatively different value dynamics under the same dt_embed_dim=0 config\"\n  relevance_score: 4\n\n- paper_id: nikishin2022primacy\n  title: \"The Primacy Bias in Deep Reinforcement Learning\"\n  authors: [Nikishin E., Schwarzer M., D'Oro P., Bacon P.-L., Courville A.]\n  year: 2022\n  venue: ICML\n  category: background\n  role: \"Identifies primacy bias — agents overfit early data and lose ability to learn from new transitions, leading to delayed performance collapse; parallels our finding where value overestimation initially appears benign but becomes pathological later, and the collapse timing is seed-dependent\"\n  relevance_score: 4\n\n- paper_id: qiao2023mind\n  title: \"Mind the Model, Not the Agent: The Primacy Bias in Model-based RL\"\n  authors: [Qiao Z., Lyu J., Li X.]\n  year: 2023\n  venue: \"arXiv:2310.15017 (ECAI 2024)\"\n  category: evaluation\n  role: \"Extends primacy bias to MBRL, testing on DreamerV2 — shows world model primacy bias dominates over agent primacy bias; directly relevant to Dreamer-family training instability and explains why some seeds recover (model escapes early overfitting) while others don't\"\n  relevance_score: 5\n\n- paper_id: hussing2024dissecting\n  title: \"Dissecting Deep RL with High Update Ratios: Combatting Value Divergence\"\n  authors: [Hussing M., Voelcker C.A., Gilitschenski I., Farahmand A.-M., Eaton E.]\n  year: 2024\n  venue: \"Reinforcement Learning Journal (RLC 2024)\"\n  category: evaluation\n  role: \"Shows value overestimation and Q-divergence under high update-to-data ratios, driven by optimizer momentum — overestimation occurs on both in-distribution and OOD data; mechanism maps to our delusional critic where imagination-trained critic inflates values progressively, with divergence onset sensitive to initialization\"\n  relevance_score: 4\n\n- paper_id: barkley2024stealing\n  title: \"Stealing That Free Lunch: Exposing the Limits of Dyna-Style Reinforcement Learning\"\n  authors: [Barkley B., Fridovich-Keil D.]\n  year: 2024\n  venue: \"arXiv:2412.14312 (ICML 2025)\"\n  category: evaluation\n  role: \"Demonstrates that synthetic rollouts (imagination) can degrade performance inconsistently across environments, with overestimation bias as a contributing factor; supports our finding that imagination-based training creates environment- and seed-dependent failure modes that existing mitigation techniques do not reliably fix\"\n  relevance_score: 3\n\n- paper_id: bjorck2022variance\n  title: \"Is High Variance Unavoidable in RL? A Case Study in Continuous Control\"\n  authors: [Bjorck J., Gomes C.P., Weinberger K.Q.]\n  year: 2022\n  venue: ICLR\n  category: background\n  role: \"Shows RL variance mostly arises early in training from poor 'outlier' runs caused by numerical instability; parallels our observation that seed 2 diverges early while seed 0 recovers — the reward prediction degradation from removing dt_embedding may create exactly this early-training instability\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Reward prediction quality → MBRL performance\n# ============================================================\n# Our key finding: removing dt_embedding causes reward_MAE to spike 75x\n# (0.01 → 0.747), making performance seed-dependent. These papers\n# establish that reward prediction quality is a known MBRL bottleneck.\n\n- paper_id: lee2024dreamsmooth\n  title: \"DreamSmooth: Improving Model-based Reinforcement Learning via Reward Smoothing\"\n  authors: [Lee V., Abbeel P., Lee Y.]\n  year: 2024\n  venue: ICLR\n  category: background\n  role: \"Directly demonstrates reward prediction is a bottleneck in MBRL — sparse/ambiguous rewards cause the reward model to predict zeros, creating gradient-free landscapes during imagination; our dt_embed_dim=0 ablation creates an analogous bottleneck where the reward head loses temporal conditioning and MAE spikes 75x\"\n  relevance_score: 5\n\n- paper_id: ma2024harmonydream\n  title: \"HarmonyDream: Task Harmonization Inside World Models\"\n  authors: [Ma H., Wu J., Feng N., Xiao C., Li D., Hao J., Wang J., Long M.]\n  year: 2024\n  venue: ICML\n  category: background\n  role: \"Shows observation prediction dominates reward prediction in world model training, degrading reward model quality; proposes dynamic loss balancing for 10-69% gains — directly relevant to our finding that dt_embedding removal disrupts the observation-reward prediction balance and causes reward MAE explosion\"\n  relevance_score: 5\n\n- paper_id: lambert2020objective\n  title: \"Objective Mismatch in Model-based Reinforcement Learning\"\n  authors: [Lambert N., Amos B., Yadan O., Calandra R.]\n  year: 2020\n  venue: \"L4DC (Proceedings of Machine Learning Research, vol. 120)\"\n  category: background\n  role: \"Formalizes that one-step prediction likelihood does not correlate with control performance — the 'objective mismatch' problem; our work reveals a specific instance: the reward head's prediction accuracy (measured by MAE) directly gates whether the critic can learn stable value estimates, creating a reward-specific objective mismatch\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: Auxiliary tasks & representation coupling in world models\n# ============================================================\n# Our finding: reward prediction quality is tightly coupled to temporal\n# conditioning (dt_embedding). Removing the embedding degrades the\n# reward head while dynamics remain intact — suggesting the reward head\n# acts as more than a passive predictor; it conditions the shared\n# representation. Literature gap: no prior work studies this coupling\n# specifically in Dreamer-family world models.\n\n- paper_id: jaderberg2017unreal\n  title: \"Reinforcement Learning with Unsupervised Auxiliary Tasks\"\n  authors: [Jaderberg M., Mnih V., Czarnecki W.M., Schaul T., Leibo J.Z., Silver D., Kavukcuoglu K.]\n  year: 2017\n  venue: ICLR\n  category: background\n  role: \"UNREAL — introduces reward prediction as an auxiliary task that shapes shared representations; foundational evidence that reward prediction is not just a passive output but actively conditions what features the network learns — our finding that removing dt_embedding selectively degrades reward prediction (but not dynamics) suggests the temporal conditioning specifically enables reward-relevant feature extraction\"\n  relevance_score: 4\n\n- paper_id: lyle2021auxiliary\n  title: \"On The Effect of Auxiliary Tasks on Representation Dynamics\"\n  authors: [Lyle C., Rowland M., Ostrovski G., Dabney W.]\n  year: 2021\n  venue: AISTATS\n  category: background\n  role: \"Theoretical analysis showing auxiliary tasks shape representations toward top eigenvectors of the transition operator; provides formal grounding for why removing temporal conditioning from the reward head could alter the entire representation — the reward head's gradients contribute to spectral structure of the shared latent space\"\n  relevance_score: 4\n\n# ============================================================\n# NEW: DreamerV3 architecture improvements (2025-2026)\n# ============================================================\n\n- paper_id: bredis2026nedreamer\n  title: \"Next Embedding Prediction Makes World Models Stronger\"\n  authors: [Bredis G., Balagansky N., Gavrilov D., Rakhimov R.]\n  year: 2026\n  venue: \"arXiv:2603.02765\"\n  category: background\n  role: \"NE-Dreamer — decoder-free MBRL replacing pixel reconstruction with next-embedding prediction via temporal transformer + Barlow Twins; improves RSSM prediction quality on DMC and DMLab but does not address temporal abstraction or delusional critic — orthogonal to our dt-embedding diagnosis\"\n  relevance_score: 3\n\n- paper_id: zhang2025dymodreamer\n  title: \"DyMoDreamer: World Modeling with Dynamic Modulation\"\n  authors: [Zhang B., Wang R., Xiao W., Zhang W., Sun J., Huang G., Chen J., Wang G.]\n  year: 2025\n  venue: NeurIPS\n  category: background\n  role: \"Modulates RSSM via inter-frame differencing mask and stochastic categorical dynamic modulation; SOTA on Atari 100k (156.6% HNS) and DMC (832) — improves dynamics extraction but does not address variable-rate imagination or dt_embedding-induced value overestimation\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Temporal abstraction methods\n# ============================================================\n\n- paper_id: liu2025vanta\n  title: \"Semantic Temporal Abstraction via Vision-Language Model Guidance for Efficient Reinforcement Learning\"\n  authors: [Liu T.-S., Liu X.-H., Chen R., Jin L., Wang P., Zhang Z., Yu Y.]\n  year: 2025\n  venue: ICLR\n  category: method-component\n  role: \"VanTA — VLM-guided trajectory decomposition into semantically meaningful skills via vector quantization + relabeling; operates at high-level skill abstraction (Franka Kitchen, Crafter) — contrasts with our low-level dt-based temporal abstraction within world-model imagination steps\"\n  relevance_score: 3\n\n# ============================================================\n# NEW: Evaluation methodology\n# ============================================================\n\n- paper_id: agarwal2021precipice\n  title: \"Deep Reinforcement Learning at the Edge of the Statistical Precipice\"\n  authors: [Agarwal R., Schwarzer M., Castro P.S., Courville A.C., Bellemare M.]\n  year: 2021\n  venue: NeurIPS\n  category: evaluation\n  role: \"Proposes rliable — interval estimates, performance profiles, IQM for robust multi-seed RL evaluation (NeurIPS Outstanding Paper); our multi-seed experiment design follows this methodology to ensure statistical validity of collapse detection across seeds\"\n  relevance_score: 4\n",
    "structuredPatch": [
      {
        "oldStart": 1,
        "oldLines": 6,
        "newStart": 1,
        "newLines": 6,
        "lines": [
          " # Literature Map — event-gated-adaptive-horizon",
          " # Last updated: 2026-05-14",
          "-# Total: 43 papers (5 existing + 38 new)",
          "+# Total: 45 papers (5 existing + 40 new)",
          " ",
          " # ============================================================",
          " # EXISTING CITATIONS (already in paper.tex)"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 46_

验证最终文件中 direct-competitor 只剩 THICK、Hieros、Director 三篇。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "9c865a17-c795-4e99-9ae8-e732aa36b094",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014MNEHjrcV6HFWC6szK2nTU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 343,
      "cache_read_input_tokens": 48190,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 343
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

### Tool call

_source line 47_

<details open><summary>🔧 Tool call — Grep · `toolu_013v4bX8mEEk8gV63uB91rvi`</summary>

```json
{
  "pattern": "direct-competitor",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/literature_map.yaml",
  "output_mode": "content",
  "-B": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "678024dc-1742-45d5-a2bf-d77edb9a354d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014MNEHjrcV6HFWC6szK2nTU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 343,
      "cache_read_input_tokens": 48190,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 343
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

### Tool result

_source line 48 · 2026-05-14T14:58:17.018Z_

<details><summary>↩ Tool result · `toolu_013v4bX8mEEk8gV63uB91rvi`</summary>

```text
207-  year: 2022
208-  venue: NeurIPS
209:  category: direct-competitor
--
304-  year: 2024
305-  venue: ICLR
306:  category: direct-competitor
--
313-  year: 2024
314-  venue: ICML
315:  category: direct-competitor
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "1340f488-d523-4480-9101-a879f80ccd16",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "207-  year: 2022\n208-  venue: NeurIPS\n209:  category: direct-competitor\n--\n304-  year: 2024\n305-  venue: ICLR\n306:  category: direct-competitor\n--\n313-  year: 2024\n314-  venue: ICML\n315:  category: direct-competitor",
    "numLines": 11
  }
}
```

</details>

---

### Assistant

_source line 49_

确认 `direct-competitor` 仅剩 3 篇：Director (hafner2022director)、THICK (gumbsch2024thick)、Hieros (mattes2024hieros)。

## 修改汇总

| # | 操作 | paper_id | 变更 |
|---|------|----------|------|
| 1 | **新增** | `hansen2024tdmpc2` | TD-MPC2 (Hansen et al., ICLR 2024, arXiv:2310.16828), category=background |
| 2 | **新增** | `yu2020mopo` | MOPO (Yu et al., NeurIPS 2020, arXiv:2005.13239), category=background |
| 3 | category 改 | `micheli2023iris` | direct-competitor → background |
| 4 | category 改 | `robine2023twm` | direct-competitor → background |
| 5 | category 改 | `chen2022transdreamer` | direct-competitor → background |
| 6 | category 改 | `bredis2026nedreamer` | direct-competitor → background |
| 7 | category 改 | `zhang2025dymodreamer` | direct-competitor → background |

总数 43 → 45 篇。direct-competitor 从 8 篇收缩到 3 篇（Director、THICK、Hieros）。两篇新文献的 role 字段已内嵌审稿人 defense 要点。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "uuid": "6029c346-58a7-4eac-bef2-0db8d5621b22",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qbw6BHKXH139zYGfChokjE",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 271,
      "cache_read_input_tokens": 48533,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 271
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

_source line 50_

确认 `direct-competitor` 仅剩 3 篇：Director (hafner2022director)、THICK (gumbsch2024thick)、Hieros (mattes2024hieros)。

## 修改汇总

| # | 操作 | paper_id | 变更 |
|---|------|----------|------|
| 1 | **新增** | `hansen2024tdmpc2` | TD-MPC2 (Hansen et al., ICLR 2024, arXiv:2310.16828), category=background |
| 2 | **新增** | `yu2020mopo` | MOPO (Yu et al., NeurIPS 2020, arXiv:2005.13239), category=background |
| 3 | category 改 | `micheli2023iris` | direct-competitor → background |
| 4 | category 改 | `robine2023twm` | direct-competitor → background |
| 5 | category 改 | `chen2022transdreamer` | direct-competitor → background |
| 6 | category 改 | `bredis2026nedreamer` | direct-competitor → background |
| 7 | category 改 | `zhang2025dymodreamer` | direct-competitor → background |

总数 43 → 45 篇。direct-competitor 从 8 篇收缩到 3 篇（Director、THICK、Hieros）。两篇新文献的 role 字段已内嵌审稿人 defense 要点。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 115379,
  "duration_api_ms": 122598,
  "num_turns": 19,
  "stop_reason": "end_turn",
  "session_id": "60a31247-3a46-4eba-8558-71dc2b49650a",
  "total_cost_usd": 0.5951062500000001,
  "usage": {
    "input_tokens": 12,
    "cache_creation_input_tokens": 37357,
    "cache_read_input_tokens": 273634,
    "output_tokens": 6720,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 37357,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 395,
        "cache_read_input_tokens": 48533,
        "cache_creation_input_tokens": 271,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 271
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 31973,
      "outputTokens": 955,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 2,
      "costUSD": 0.056748,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 12,
      "outputTokens": 6720,
      "cacheReadInputTokens": 273634,
      "cacheCreationInputTokens": 37357,
      "webSearchRequests": 0,
      "costUSD": 0.53835825,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "202219db-43a9-43c2-a0a3-a062195df12a"
}
```

</details>

---
