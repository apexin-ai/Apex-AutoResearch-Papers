# ops arr submission form

**What Can IRT Person-Fit Statistics Reveal About SFT-Stage Benchmark Contamination?** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 38
- **Recorded user turns:** 0
- **Tool calls:** 14
- **Original source:** `logs/workers/worker_ops_arr-submission-form_20260523T041551.log`
- **Structured JSON:** [`a89c2abe55bd4f7b90cf.json`](../../sessions/a8/a89c2abe55bd4f7b90cf.json)

## Before a recorded user message

38 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
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
  "uuid": "7fda6c3c-cf9d-43dc-b7e5-ae8125736f9e",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude/projects/-home-ubuntu--agent-ml-research-be-idea-gen-0519-3-projects-irt-personfit-contam/memory/"
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
    "resetsAt": 1779525600,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "d19912a2-3532-4b6b-9b43-1035fe2b3604",
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the main.tex to extract the title and abstract, and then read the relevant sections to answer the checklist questions.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "b1dca9c6-f04c-4fc4-8d53-321ffe1b585e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PJvDyuqNq4r9fvxz51xvAC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12387,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12387
      },
      "output_tokens": 25,
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

_source line 5_

I'll read the paper's main file and key sections to extract the needed information.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "06a1abe0-e4d6-49b1-b80c-210171939dc5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PJvDyuqNq4r9fvxz51xvAC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12387,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12387
      },
      "output_tokens": 25,
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

_source line 6_

<details open><summary>🔧 Tool call — Read · `toolu_014KMQNnzCp5itPsQ595nNbK`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "0ec17903-f4e7-45a9-8e19-32c2cf73f2b1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PJvDyuqNq4r9fvxz51xvAC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12387,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12387
      },
      "output_tokens": 25,
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

_source line 7 · 2026-05-23T04:16:03.638Z_

<details><summary>↩ Tool result · `toolu_014KMQNnzCp5itPsQ595nNbK`</summary>

```text
1	\documentclass[11pt]{article}
2	\usepackage[review]{acl}
3	\usepackage{times}
4	\usepackage{latexsym}
5	\usepackage[T1]{fontenc}
6	\usepackage[utf8]{inputenc}
7	\usepackage{microtype}
8	\usepackage{graphicx}
9	\usepackage{booktabs}
10	\usepackage{amsmath}
11	\usepackage{amssymb}
12	\usepackage{multirow}
13	\usepackage{xcolor}
14	\usepackage{subcaption}
15	\usepackage{enumitem}
16	
17	\newcommand{\irtfit}{\textsc{IRT-FIT}}
18	
19	\graphicspath{{../figures/paper/}}
20	
21	\title{What Can IRT Person-Fit Statistics Reveal About SFT-Stage Benchmark Contamination?}
22	
23	\author{Anonymous}
24	
25	\begin{document}
26	\maketitle
27	
28	\begin{abstract}
29	\input{sections/abstract}
30	\end{abstract}
31	
32	\input{sections/introduction}
33	\input{sections/related_work}
34	\input{sections/method}
35	\input{sections/results}
36	\input{sections/discussion}
37	\input{sections/conclusion}
38	
39	\input{sections/limitations}
40	
41	\section*{Reproducibility Statement}
42	Code and response data will be released upon acceptance.
43	Bootstrap confidence intervals use the percentile method with 10,000 resamples.
44	All three model families use clean baseline seeds 0--9 ($n{=}10$ per family).
45	Pre-calibrated 4PL item parameters are from the publicly available PSN-IRT item bank \citep{psnirt2026}.
46	
47	\bibliography{references}
48	
49	\appendix
50	\input{sections/appendix}
51	
52	\end{document}
53	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "71466acf-25c1-4d0d-a14e-56f3642880e7",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/main.tex",
      "content": "\\documentclass[11pt]{article}\n\\usepackage[review]{acl}\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{multirow}\n\\usepackage{xcolor}\n\\usepackage{subcaption}\n\\usepackage{enumitem}\n\n\\newcommand{\\irtfit}{\\textsc{IRT-FIT}}\n\n\\graphicspath{{../figures/paper/}}\n\n\\title{What Can IRT Person-Fit Statistics Reveal About SFT-Stage Benchmark Contamination?}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\begin{abstract}\n\\input{sections/abstract}\n\\end{abstract}\n\n\\input{sections/introduction}\n\\input{sections/related_work}\n\\input{sections/method}\n\\input{sections/results}\n\\input{sections/discussion}\n\\input{sections/conclusion}\n\n\\input{sections/limitations}\n\n\\section*{Reproducibility Statement}\nCode and response data will be released upon acceptance.\nBootstrap confidence intervals use the percentile method with 10,000 resamples.\nAll three model families use clean baseline seeds 0--9 ($n{=}10$ per family).\nPre-calibrated 4PL item parameters are from the publicly available PSN-IRT item bank \\citep{psnirt2026}.\n\n\\bibliography{references}\n\n\\appendix\n\\input{sections/appendix}\n\n\\end{document}\n",
      "numLines": 53,
      "startLine": 1,
      "totalLines": 53
    }
  }
}
```

</details>

---

### Tool call

_source line 8_

<details open><summary>🔧 Tool call — Glob · `toolu_01J3C6KhZ6CGCFzSs41ZaHmg`</summary>

```json
{
  "pattern": "sections/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "b267188b-73b5-4aec-bdf3-1771f46082d7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PJvDyuqNq4r9fvxz51xvAC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12387,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12387
      },
      "output_tokens": 25,
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

_source line 9 · 2026-05-23T04:16:04.170Z_

<details><summary>↩ Tool result · `toolu_01J3C6KhZ6CGCFzSs41ZaHmg`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "ddbd37ab-1d2e-4d5c-acf3-16b6b766ce52",
  "tool_use_result": {
    "filenames": [],
    "durationMs": 11,
    "numFiles": 0,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 10_

<details open><summary>🔧 Tool call — Glob · `toolu_01Nx1TK7ZNM3XSs23uXdSuRp`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "f4a4662c-d0b6-43a7-b109-f863afc98243",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0118v4B3mWYYPTkswrY89jM5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 849,
      "cache_read_input_tokens": 24228,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 849
      },
      "output_tokens": 70,
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

_source line 11 · 2026-05-23T04:16:06.036Z_

<details><summary>↩ Tool result · `toolu_01Nx1TK7ZNM3XSs23uXdSuRp`</summary>

```text
paper/sections/experiments.tex
paper/sections/background.tex
paper/sections/sec_empirical.tex
paper/sections/sec_simulation.tex
paper/sections/sec_setup.tex
paper/sections/sec_ctrl_contam.tex
paper/sections/related_work.tex
paper/main.tex
paper/sections/method.tex
paper/sections/abstract.tex
paper/sections/conclusion.tex
paper/sections/introduction.tex
paper/sections/results.tex
paper/sections/discussion.tex
paper/sections/appendix.tex
paper/sections/limitations.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "52095e50-df8e-4808-8e6b-f77d5381e363",
  "tool_use_result": {
    "filenames": [
      "paper/sections/experiments.tex",
      "paper/sections/background.tex",
      "paper/sections/sec_empirical.tex",
      "paper/sections/sec_simulation.tex",
      "paper/sections/sec_setup.tex",
      "paper/sections/sec_ctrl_contam.tex",
      "paper/sections/related_work.tex",
      "paper/main.tex",
      "paper/sections/method.tex",
      "paper/sections/abstract.tex",
      "paper/sections/conclusion.tex",
      "paper/sections/introduction.tex",
      "paper/sections/results.tex",
      "paper/sections/discussion.tex",
      "paper/sections/appendix.tex",
      "paper/sections/limitations.tex"
    ],
    "durationMs": 5,
    "numFiles": 16,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 12_

<details open><summary>🔧 Tool call — Read · `toolu_012MZee7YA9V8n3Vq6uqomuH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "26d8a8b9-b98f-46f0-8201-d4940b74ffd8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KvNyRMRnYCXyZe3QhH9Tg1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 256,
      "cache_read_input_tokens": 25077,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 256
      },
      "output_tokens": 65,
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

_source line 13 · 2026-05-23T04:16:08.176Z_

<details><summary>↩ Tool result · `toolu_012MZee7YA9V8n3Vq6uqomuH`</summary>

```text
1	Benchmark contamination in Large Language Models (LLMs) undermines evaluation validity, yet most detection methods require privileged access to training data, model internals, or output probabilities.
2	We present the first controlled characterization of IRT person-fit statistics for detecting SFT-stage contamination: the framework requires only binary response patterns from the target model---no access to weights, gradients, logits, or training data---combined with externally calibrated 4PL item parameters from a large-scale item bank; diagnostic $\theta$-anchoring additionally requires a clean baseline.
3	A contaminated LLM produces aberrant response patterns analogous to a test-taker with item preknowledge.
4	Using $\ell_z^*$ in a matched-difference design ($\Delta\ell_z^*$) across three 7--8B model families ($n{=}10$ clean baseline seeds per model family) on MMLU (14,042 items) and ARC-Challenge (295 items), we identify three behavior boundaries:
5	(1) model-specific $\theta$-shift dynamics, where contamination-induced ability inflation absorbs the person-fit signal; $\theta$-anchoring is necessary for reliable detection of high-ability models at high contamination (2.4$\times$ amplification, inter-seed CV reduced from 60\% to 19\%);
6	(2) a detection-diagnosis tradeoff where simpler statistics yield stronger detection but lack $\ell_z^*$'s diagnostic capabilities (seen/unseen decomposition, mechanistic $\theta$-shift analysis);
7	and (3, exploratory) ability-dependent non-monotonic dose-response under free-$\theta$ estimation, driven by $\theta$-shift absorption; $\theta$-anchored analysis reveals stable detection with a strong positive dose-response at higher contamination levels.
8	These findings establish when and why binary response patterns carry contamination information beyond aggregate accuracy.
9	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "b4cc0b6e-f326-41fd-9fee-22a1d62da7e0",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex",
      "content": "Benchmark contamination in Large Language Models (LLMs) undermines evaluation validity, yet most detection methods require privileged access to training data, model internals, or output probabilities.\nWe present the first controlled characterization of IRT person-fit statistics for detecting SFT-stage contamination: the framework requires only binary response patterns from the target model---no access to weights, gradients, logits, or training data---combined with externally calibrated 4PL item parameters from a large-scale item bank; diagnostic $\\theta$-anchoring additionally requires a clean baseline.\nA contaminated LLM produces aberrant response patterns analogous to a test-taker with item preknowledge.\nUsing $\\ell_z^*$ in a matched-difference design ($\\Delta\\ell_z^*$) across three 7--8B model families ($n{=}10$ clean baseline seeds per model family) on MMLU (14,042 items) and ARC-Challenge (295 items), we identify three behavior boundaries:\n(1) model-specific $\\theta$-shift dynamics, where contamination-induced ability inflation absorbs the person-fit signal; $\\theta$-anchoring is necessary for reliable detection of high-ability models at high contamination (2.4$\\times$ amplification, inter-seed CV reduced from 60\\% to 19\\%);\n(2) a detection-diagnosis tradeoff where simpler statistics yield stronger detection but lack $\\ell_z^*$'s diagnostic capabilities (seen/unseen decomposition, mechanistic $\\theta$-shift analysis);\nand (3, exploratory) ability-dependent non-monotonic dose-response under free-$\\theta$ estimation, driven by $\\theta$-shift absorption; $\\theta$-anchored analysis reveals stable detection with a strong positive dose-response at higher contamination levels.\nThese findings establish when and why binary response patterns carry contamination information beyond aggregate accuracy.\n",
      "numLines": 9,
      "startLine": 1,
      "totalLines": 9
    }
  }
}
```

</details>

---

### Tool call

_source line 14_

<details open><summary>🔧 Tool call — Read · `toolu_011wvVSUindNorsspWa8Aqs5`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "062d0e57-4a78-40f6-8342-4b2d4b31d0b0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KvNyRMRnYCXyZe3QhH9Tg1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 256,
      "cache_read_input_tokens": 25077,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 256
      },
      "output_tokens": 65,
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

_source line 15 · 2026-05-23T04:16:08.611Z_

<details><summary>↩ Tool result · `toolu_011wvVSUindNorsspWa8Aqs5`</summary>

```text
1	\section*{Limitations}
2	
3	Our controlled experiments cover three 7--8B model families with QLoRA fine-tuning; generalization to larger scales, mixture-of-experts architectures, full-parameter fine-tuning, and pretraining-stage contamination remains untested.
4	Most contamination conditions use a single training run, and multi-seed replication (available for Qwen) reveals high seed dependence at 50\% contamination (CV${=}$60\%), partially resolved by $\theta$-anchoring; the post-RL characterization is $N{=}1$.
5	The framework depends on pre-calibrated 4PL item parameters from PSN-IRT, whose calibration sample may include contaminated models, and we do not provide head-to-head comparison with logit-based methods (MIA, ConStat) that operate at a different information level.
6	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "601df313-448d-4c84-86ca-4a3c6cfc2e48",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex",
      "content": "\\section*{Limitations}\n\nOur controlled experiments cover three 7--8B model families with QLoRA fine-tuning; generalization to larger scales, mixture-of-experts architectures, full-parameter fine-tuning, and pretraining-stage contamination remains untested.\nMost contamination conditions use a single training run, and multi-seed replication (available for Qwen) reveals high seed dependence at 50\\% contamination (CV${=}$60\\%), partially resolved by $\\theta$-anchoring; the post-RL characterization is $N{=}1$.\nThe framework depends on pre-calibrated 4PL item parameters from PSN-IRT, whose calibration sample may include contaminated models, and we do not provide head-to-head comparison with logit-based methods (MIA, ConStat) that operate at a different information level.\n",
      "numLines": 6,
      "startLine": 1,
      "totalLines": 6
    }
  }
}
```

</details>

---

### Tool call

_source line 16_

<details open><summary>🔧 Tool call — Read · `toolu_01Aezdvz1MHc331aRxCQCwgi`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "192206c1-353c-470a-a1ff-d1752b6001c0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KvNyRMRnYCXyZe3QhH9Tg1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 256,
      "cache_read_input_tokens": 25077,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 256
      },
      "output_tokens": 65,
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

_source line 17 · 2026-05-23T04:16:09.286Z_

<details><summary>↩ Tool result · `toolu_01Aezdvz1MHc331aRxCQCwgi`</summary>

```text
1	\section{Simulation Validation}
2	\label{app:simulation}
3	
4	Under the null (no contamination), bootstrap $\ell_z^*$ tracks $\mathcal{N}(0,1)$: mean bias 0.041 and standard deviation 1.003 on MMLU.
5	Kolmogorov--Smirnov rejection rates vary with benchmark size: 8.3\% for MMLU and HellaSwag ($n > 10{,}000$), 50.0\% for GSM8K ($n = 1{,}319$), 58.3\% for ARC-C ($n = 295$), and 75.0\% for HumanEval ($n = 164$).
6	$\ell_z^*$ is well-calibrated for benchmarks with $n \geq 10{,}000$ items; smaller benchmarks show increasing finite-sample deviations from normality.
7	
8	Two-sided testing eliminates the inverted-U artifact: MMLU achieves 97.8\% power at 15\% contamination and sustains ${>}$93\% at all levels.
9	Power scales with $\sqrt{n}$, as predicted by the noncentrality parameter $\delta \propto \sqrt{n}$.
10	The empirical power function, derived via Gauss--Hermite quadrature ($K=30$) over the ability distribution, achieves $R^2 = 0.957$ against simulated values, with approximate minimum benchmark size of $n \geq 7{,}958$ items for 80\% power at 15\% contamination under MMLU item parameters.
11	
12	\section{4PL vs.\ 3PL Ablation Details}
13	\label{app:4pl_ablation}
14	
15	Table~\ref{tab:4pl_3pl_power} reports detection power (proportion of 2{,}000 simulation replicates rejecting $H_0$ at $\alpha{=}0.05$, two-sided) for 4PL and 3PL parameterizations across five benchmarks and seven contamination levels.
16	The 4PL model yields higher power than 3PL at every non-trivial contamination level on every benchmark.
17	The advantage is largest on MMLU and HellaSwag, where upper-asymptote ($d < 1$) violations are most prevalent, and smallest on ARC-Challenge and HumanEval, where limited item counts constrain power under both parameterizations.
18	
19	Power is non-monotonic at 75\% contamination under 4PL on four of five benchmarks (e.g., MMLU: $.952 \to .938$; GSM8K: $.846 \to .802$).
20	This reflects the $\theta$-shift boundary condition described in \S\ref{sec:inverted_u}: at high contamination fractions, re-estimated $\hat{\theta}$ absorbs part of the aberrance signal, reducing $|\ell_z^*|$.
21	At 100\% contamination, all items are seen and power reaches 1.000 trivially.
22	The 4PL advantage over 3PL depends on accurate estimation of the upper asymptote $d$; with estimation error exceeding ${\sim}10\%$, the effective model behavior approaches 3PL ($d{=}1$) and the power gain diminishes.
23	PSN-IRT's large calibration sample ($12{+}$ models per item) typically yields $d$ standard errors well below this threshold.
24	
25	\begin{table*}[t]
26	\centering
27	\caption{Detection power (proportion rejecting $H_0$ at $\alpha{=}0.05$) under 4PL and 3PL parameterizations across benchmarks and contamination levels ($n{=}2{,}000$ replicates per cell). Bold indicates the 4PL advantage exceeds 5\,pp.}
28	\label{tab:4pl_3pl_power}
29	\small
30	\begin{tabular}{@{}llccccccc@{}}
31	\toprule
32	Benchmark & IRT & 5\% & 10\% & 15\% & 25\% & 50\% & 75\% & 100\% \\
33	\midrule
34	MMLU & 4PL & \textbf{.476} & \textbf{.848} & \textbf{.969} & \textbf{.983} & \textbf{.952} & \textbf{.938} & 1.00 \\
35	     & 3PL & .227 & .340 & .412 & .521 & .676 & .770 & 1.00 \\
36	\addlinespace
37	HellaSwag & 4PL & \textbf{.251} & \textbf{.454} & \textbf{.656} & \textbf{.915} & \textbf{.939} & \textbf{.919} & 1.00 \\
38	          & 3PL & .167 & .241 & .313 & .368 & .508 & .642 & 1.00 \\
39	\addlinespace
40	GSM8K & 4PL & \textbf{.156} & \textbf{.309} & \textbf{.492} & \textbf{.737} & \textbf{.846} & \textbf{.802} & 1.00 \\
41	      & 3PL & .102 & .172 & .285 & .396 & .567 & .577 & 1.00 \\
42	\addlinespace
43	ARC-C & 4PL & .057 & .075 & .087 & \textbf{.130} & \textbf{.285} & \textbf{.493} & 1.00 \\
44	      & 3PL & .054 & .062 & .071 & .076 & .110 & .102 & 1.00 \\
45	\addlinespace
46	HumanEval & 4PL & .076 & .121 & \textbf{.197} & \textbf{.302} & \textbf{.554} & \textbf{.521} & 1.00 \\
47	          & 3PL & .063 & .086 & .120 & .182 & .281 & .315 & 1.00 \\
48	\bottomrule
49	\end{tabular}
50	\end{table*}
51	
52	\section{Seed Sensitivity Analysis}
53	\label{app:seed_sensitivity}
54	
55	\paragraph{Clean-baseline variability.}
56	Table~\ref{tab:seed_sensitivity} reports $\ell_z^*$, accuracy, and $\hat{\theta}_{\text{MLE}}$ across three independent QLoRA runs (seeds 42, 123, 456).
57	For Qwen2.5-7B, $\ell_z^*$ ranges from $7.05$ (seed 123) to $9.53$ (seed 456); the lower value of seed 123 likely reflects seed-specific training dynamics (random initialization, data ordering), but all three seeds produce $\ell_z^* \gg 1.96$, confirming that the elevated baseline reflects systematic model--benchmark misfit rather than seed-specific artifacts.
58	Llama-3.1-8B shows $\ell_z^*$ near zero ($-0.14 \pm 0.97$), consistent with lower baseline misfit.
59	Accuracy variability is negligible for both families (CV $< 0.004$).
60	
61	\begin{table}[t]
62	\centering
63	\caption{Seed sensitivity analysis for clean baseline across three independent runs (seeds 42, 123, 456). CV = coefficient of variation ($\mathrm{std}/|\mathrm{mean}|$). These $n{=}3$ pilot results are superseded by the $n{=}10$ analysis in \S\ref{sec:detection}; retained for methodological transparency.}
64	\label{tab:seed_sensitivity}
65	\footnotesize
66	\resizebox{\columnwidth}{!}{%
67	\begin{tabular}{@{}llcccc@{}}
68	\toprule
69	Model & Metric & Mean & Std & Range & CV \\
70	\midrule
71	Qwen2.5-7B & $\ell_z^*$ & 8.684 & 1.412 & 2.475 & 0.163 \\
72	 & Accuracy & 0.679 & 0.000 & 0.001 & 0.001 \\
73	 & $\hat{\theta}_{\mathrm{MLE}}$ & $-$0.097 & 0.012 & 0.023 & 0.119 \\
74	\midrule
75	Llama-3.1-8B & $\ell_z^*$ & $-$0.141 & 0.965 & 1.929 & 6.860 \\
76	 & Accuracy & 0.594 & 0.002 & 0.004 & 0.004 \\
77	 & $\hat{\theta}_{\mathrm{MLE}}$ & $-$0.645 & 0.019 & 0.036 & 0.029 \\
78	\bottomrule
79	\end{tabular}}
80	\end{table}
81	
82	\paragraph{Cohen's $d$ confidence intervals.}
83	Table~\ref{tab:cohens_d_ci} reports Cohen's $d$ effect sizes with both analytic and bootstrap 95\% confidence intervals.
84	Analytic CIs use $d \pm t_{0.025,\,\text{df}=2} \cdot \text{SE}_d$; with only $n{=}3$ clean seeds (df${=}2$), the critical value $t_{0.025,2} = 4.303$ produces intervals wide enough to cross zero in all four conditions.
85	This is a known limitation of small-sample $t$-based intervals rather than evidence of null effects.
86	Bootstrap CIs (10{,}000 resamples with replacement from the three clean seeds) provide a nonparametric alternative: all four bootstrap intervals exclude zero, supporting the conclusion that contamination produces a reliably detectable signal despite the small reference sample.
87	
88	\begin{table}[t]
89	\centering
90	\caption{Cohen's $d$ with 95\% confidence intervals for contaminated conditions relative to clean baselines ($n{=}3$ seeds). Analytic CIs use $t_{0.025, \text{df}=2}$; bootstrap CIs use 10{,}000 resamples. These $n{=}3$ pilot results are superseded by the $n{=}10$ analysis in \S\ref{sec:detection}; retained for methodological transparency.}
91	\label{tab:cohens_d_ci}
92	\footnotesize
93	\resizebox{\columnwidth}{!}{%
94	\begin{tabular}{@{}llccc@{}}
95	\toprule
96	Model & Cond. & $d$ & Analytic CI & Bootstrap CI \\
97	\midrule
98	Qwen & 15\% & $-$3.42 & [$-$9.92, 3.08] & [$-$3.45, $-$2.82] \\
99	 & 50\% & $-$0.99 & [$-$4.02, 2.04] & [$-$0.99, $-$0.41] \\
100	\midrule
101	Llama & 15\% & $-$2.95 & [$-$8.70, 2.80] & [$-$5.89, $-$2.29] \\
102	 & 50\% & $-$3.31 & [$-$9.63, 3.01] & [$-$6.47, $-$2.59] \\
103	\bottomrule
104	\end{tabular}}
105	\end{table}
106	
107	\paragraph{Cross-family consistency.}
108	Table~\ref{tab:cross_family} confirms that both model families produce large negative Cohen's $d$ under contamination.
109	The $|\Delta d| = 2.32$ gap at 50\% contamination reflects Qwen's non-monotonic dose-response (the $\theta$-shift boundary condition; \S\ref{sec:inverted_u}), not a failure of detection robustness---both families remain well above conventional large-effect thresholds ($|d| > 0.8$) at both contamination levels.
110	
111	\begin{table}[t]
112	\centering
113	\caption{Cross-family consistency of contamination detection ($n{=}3$ pilot). Both families show large negative $d$ under contamination. Superseded by $n{=}10$ results in \S\ref{sec:detection}; retained for methodological transparency.}
114	\label{tab:cross_family}
115	\small
116	\begin{tabular}{@{}lcccl@{}}
117	\toprule
118	Condition & Qwen $d$ & Llama $d$ & $|\Delta d|$ & Consistent? \\
119	\midrule
120	15\% contam. & $-$3.42 & $-$2.95 & 0.47 & Yes \\
121	50\% contam. & $-$0.99 & $-$3.31 & 2.32 & Yes \\
122	\bottomrule
123	\end{tabular}
124	\end{table}
125	
126	\section{Baseline $\ell_z^*$ Interpretation}
127	\label{app:baseline_meaning}
128	
129	The baseline $\ell_z^*$ value reflects a model's difficulty-ordering consistency under the 4PL model, not its accuracy alone.
130	In the empirical data, Mistral ($\text{acc}{=}0.514$, lowest among the 12 models) exhibits $\ell_z^*{=}{+}5.42$ (second highest), because its response pattern follows the IRT-predicted difficulty ordering more closely than higher-accuracy models whose responses violate the assumed item structure.
131	This dissociation explains why Mistral produces the strongest contamination signal despite the lowest accuracy: its lower baseline ability ($\hat{\theta}{=}{-}1.16$) provides greater $\theta$-shift headroom.
132	
133	\section{Item-Level Detection Results}
134	\label{app:item_auroc}
135	
136	Table~\ref{tab:item_auroc} reports item-level contamination detection performance at 15\% contamination on MMLU.
137	All methods perform near random (AUROC $\leq 0.63$), confirming that contamination is diffuse across the response pattern and that model-level aggregation via $\ell_z^*$ is essential.
138	
139	An accuracy $z$-score baseline yields $z{=}160$ at 15\% contamination, but this reflects near-zero cross-seed accuracy variance ($\text{std}{=}0.0003$), not genuine discriminability.
140	In deployment, accuracy variability from prompt format, evaluation harness, and hardware differences inflates the denominator, collapsing the $z$-score.
141	
142	\begin{table}[t]
143	\centering
144	\caption{Item-level contamination detection (AUROC) at 15\% contamination on MMLU.}
145	\label{tab:item_auroc}
146	\footnotesize
147	\begin{tabular}{@{}lc@{}}
148	\toprule
149	Method & AUROC \\
150	\midrule
151	Random baseline & 0.50 \\
152	$\ell_z^*$ itemwise & 0.53 \\
153	LR cross-model & 0.59 \\
154	RF cross-model & 0.63 \\
155	\bottomrule
156	\end{tabular}
157	\end{table}
158	
159	\section{Robustness Analysis}
160	\label{app:robustness}
161	
162	\subsection{$\Delta\ell_z^*$ Under Local Dependence}
163	\label{app:local_dep}
164	
165	IRT person-fit statistics assume local independence---conditional on $\theta$, item responses are independent.
166	LLM benchmarks violate this assumption through topical clustering (e.g., MMLU subjects); resampling-based approaches can provide valid person-fit assessment even under such violations \citep{sinharay2016}.
167	We evaluate whether the $\Delta\ell_z^*$ matched-difference design is robust to local dependence (LD) via two simulation scenarios on 14,042 MMLU items with 1,000 replications each.
168	
169	\paragraph{Shared LD.}
170	Clean and contaminated conditions share identical testlet structure (${\sim}200$ testlets of ${\sim}70$ items, random effect $\gamma_t \sim \mathcal{N}(0, \sigma_\tau)$).
171	Table~\ref{tab:ld_shared} reports absolute $\ell_z^*$ Type~I error and the ratio of $\Delta\ell_z^*$ effect size ($d$) to the no-LD baseline.
172	While absolute $\ell_z^*$ Type~I error inflates severely under LD (0.043$\to$0.939 at $\sigma{=}1.0$), the $\Delta\ell_z^*$ design maintains detection power: $d_{\text{ratio}} \geq 0.93$ for $\sigma_\tau \leq 0.5$ (realistic range), confirming that shared misfit is cancelled by the matched-difference design.
173	
174	\begin{table}[t]
175	\centering
176	\caption{Robustness of $\Delta\ell_z^*$ to shared local dependence (1,000 replications, MMLU). $d_{\text{ratio}}$: effect size relative to the $\sigma_\tau{=}0$ baseline.}
177	\label{tab:ld_shared}
178	\footnotesize
179	\begin{tabular}{@{}lccc@{}}
180	\toprule
181	$\sigma_\tau$ & Abs.\ $\ell_z^*$ Type~I & $d_{\text{ratio}}$ (15\%) & $d_{\text{ratio}}$ (50\%) \\
182	\midrule
183	0.0 & 0.043 & 1.000 & 1.000 \\
184	0.3 & 0.110 & 1.002 & 1.038 \\
185	0.5 & 0.454 & 0.934 & 1.028 \\
186	1.0 & 0.939 & 0.705 & 1.061 \\
187	\bottomrule
188	\end{tabular}
189	\end{table}
190	
191	\paragraph{Asymmetric LD.}
192	In the second scenario, contaminated models' seen items share an additional memory factor ($\gamma_{\text{mem}} \sim \mathcal{N}(0, \sigma_{\text{mem}})$), simulating contamination-specific LD not present in clean conditions ($\sigma_\tau{=}0.5$ fixed).
193	Table~\ref{tab:ld_asym} shows that $\Delta\ell_z^*$ maintains ${\geq}98.5\%$ power across all conditions, even when contamination introduces asymmetric dependence among seen items.
194	
195	\begin{table}[t]
196	\centering
197	\caption{$\Delta\ell_z^*$ detection under asymmetric local dependence ($\sigma_\tau{=}0.5$, contamination-specific memory factor $\sigma_{\text{mem}}$; 1,000 replications, MMLU).}
198	\label{tab:ld_asym}
199	\footnotesize
200	\begin{tabular}{@{}lcccc@{}}
201	\toprule
202	$\sigma_{\text{mem}}$ & Power (15\%) & $d$ (15\%) & Power (50\%) & $d$ (50\%) \\
203	\midrule
204	0.5 & 0.987 & $-$2.107 & 0.991 & $-$2.337 \\
205	1.0 & 0.993 & $-$2.104 & 0.985 & $-$1.587 \\
206	\bottomrule
207	\end{tabular}
208	\end{table}
209	
210	\subsection{Sensitivity to Item Parameter Estimation Error}
211	\label{app:param_perturb}
212	
213	PSN-IRT item parameters carry estimation error from the calibration sample.
214	We evaluate detection sensitivity by adding joint noise to all four parameters: multiplicative perturbation $p' = p \cdot (1 + \mathcal{N}(0, \sigma))$ for $a$, $c$, and $d$; additive perturbation $b' = b + \sigma \cdot \mathcal{N}(0, 1)$ for difficulty.
215	Tables~\ref{tab:param_noise_free} and \ref{tab:param_noise_fixed} report results over 100 trials using Qwen MMLU response vectors.
216	
217	Detection of 15\% contamination is robust to parameter noise under free-$\theta$ (17.4\% bias at $\sigma{=}10\%$, $|d|$ still ${>}5$; Table~\ref{tab:param_noise_free}).
218	The 50\% contamination condition under free-$\theta$ is fragile---consistent with its already-weak signal due to $\theta$-shift absorption (\S\ref{sec:inverted_u}).
219	
220	Under $\theta$-fixed estimation (Table~\ref{tab:param_noise_fixed}), detection is highly robust: 10\% perturbation produces ${<}4\%$ bias in Cohen's $d$, with worst-case $|d| = 3.73$ (15\% contamination) and $12.20$ (50\%)---both far exceeding conventional thresholds.
221	This contrasts sharply with free-$\theta$ estimation, where 50\% contamination Cohen's $d$ collapses to near zero under 10\% noise.
222	The complementarity is clear: conditions where free-$\theta$ detection is fragile (high-baseline-accuracy models with $\theta$-shift absorption) are precisely where $\theta$-fixed anchoring provides the strongest and most noise-robust signal.
223	
224	\begin{table}[t]
225	\centering
226	\caption{Sensitivity of detection to item parameter noise (100 trials, Qwen MMLU, free-$\theta$). \% bias relative to noise-free $d$.}
227	\label{tab:param_noise_free}
228	\footnotesize
229	\begin{tabular}{@{}lcccc@{}}
230	\toprule
231	Noise $\sigma$ & $d$ (15\%) & \% bias & $d$ (50\%) & \% bias \\
232	\midrule
233	0\% & $-$6.575 & --- & $-$1.897 & --- \\
234	5\% & $-$6.010 & 8.6 & $-$0.925 & 51.2 \\
235	10\% & $-$5.433 & 17.4 & $-$0.014 & 99.3 \\
236	\bottomrule
237	\end{tabular}
238	\end{table}
239	
240	\begin{table}[t]
241	\centering
242	\caption{Sensitivity of detection to item parameter noise (100 trials, Qwen MMLU, $\theta$-fixed). Worst-case $|d|$ over 100 trials in parentheses.}
243	\label{tab:param_noise_fixed}
244	\footnotesize
245	\resizebox{\columnwidth}{!}{%
246	\begin{tabular}{@{}lcccc@{}}
247	\toprule
248	Noise $\sigma$ & $d_{\text{fixed}}$ (15\%) & \% bias & $d_{\text{fixed}}$ (50\%) & \% bias \\
249	\midrule
250	0\% & 4.77 & --- & 14.52 & --- \\
251	5\% & 5.07 $\pm$ 0.24 & 6.3 & 14.76 $\pm$ 0.44 & 1.6 \\
252	10\% & 4.95 $\pm$ 0.43 (3.73) & 3.7 & 14.45 $\pm$ 0.85 (12.20) & 0.5 \\
253	\bottomrule
254	\end{tabular}}
255	\end{table}
256	
257	\section{BCa Bootstrap Sensitivity Check}
258	\label{app:bca}
259	
260	As a sensitivity check, we computed bias-corrected and accelerated (BCa) bootstrap confidence intervals for all Cohen's $d$ estimates.
261	BCa CIs were uniformly narrower than the percentile CIs reported in the main text (mean reduction 22\%), confirming that our reported intervals are conservative.
262	The single condition where BCa widens the zero-crossing set---Llama fixed-$\theta$ at 50\% contamination, BCa CI [$-$0.13, 2.21] vs.\ percentile CI [0.17, 2.97]---is already characterized as ineffective in \S\ref{sec:theta_dynamics}.
263	
264	\section{Classical IRT Refit from Leaderboard Data}
265	\label{app:mml_em}
266	
267	To assess whether item parameters can be recovered without PSN-IRT's neural calibration, we applied classical MML-EM estimation (Gauss--Hermite quadrature, $Q{=}31$ nodes) to binary response data from $N{=}178$ models on the Open LLM Leaderboard v1.
268	With 14,042 MMLU items and an examinee-to-item ratio of $N{:}J = 0.013$---far below the $N{>}500$ typically required for stable 3PL estimation---discrimination parameters are severely under-determined.
269	
270	Table~\ref{tab:mml_em} reports parameter correlations between MML-EM-fitted and PSN-IRT parameters.
271	Difficulty shows moderate agreement ($r_b{=}0.663$), but discrimination is essentially unrecovered ($r_a{=}0.127$).
272	Using these MML-EM parameters produces miscalibrated $\ell_z^*$ statistics (mean$\,{=}\,$11.2, expected ${\approx}\,$0), confirming that the refitted model does not capture the data-generating process.
273	This motivates the dependence on PSN-IRT's externally calibrated item bank (\S\ref{sec:framework}).
274	
275	\begin{table}[t]
276	\centering
277	\caption{Parameter correlation between classical MML-EM refit ($N{=}178$ models) and PSN-IRT on MMLU ($n{=}10{,}558$ matched items).}
278	\label{tab:mml_em}
279	\footnotesize
280	\begin{tabular}{@{}llcc@{}}
281	\toprule
282	Model & Parameter & Pearson $r$ & Spearman $\rho$ \\
283	\midrule
284	3PL & $a$ (discrim.) & 0.127 & 0.135 \\
285	3PL & $b$ (difficulty) & 0.663 & 0.684 \\
286	2PL & $a$ (discrim.) & $-$0.029 & 0.050 \\
287	2PL & $b$ (difficulty) & 0.608 & 0.656 \\
288	\bottomrule
289	\end{tabular}
290	\end{table}
291	
292	\section{Post-RL Preliminary Observation}
293	\label{app:post_rl}
294	
295	\citet{wang2025fragility} show that all MIA-based detectors fail after RL post-training.
296	In a single-model pilot ($N{=}1$, Qwen, GRPO), we applied GRPO \citep{shao2024} for 1,500 steps to a contaminated model (15\% MMLU) and evaluated at three checkpoints.
297	GRPO erases the accuracy gap between seen and unseen items ($11.4\text{pp} \to 2.1\text{pp}$), but the $\ell_z^*$ response-pattern gap persists (${\sim}3.3$; Figure~\ref{fig:grpo}), suggesting structural traces of contamination may survive RL alignment.
298	Min-K\% membership inference confirms this dissociation: while SFT yields a weak MIA signal (AUC-ROC${=}0.611$), GRPO training drives AUC to $0.493$ (step~500), $0.493$ (step~1000), and $0.493$ (step~1500)---indistinguishable from random chance ($0.50$) as RL erases memorization-based features while the response-pattern anomaly that $\ell_z^*$ detects persists.
299	This $N{=}1$ observation requires validation across model families, RL methods, and contamination levels before any conclusions can be drawn.
300	
301	\begin{figure}[t]
302	  \centering
303	  \includegraphics[width=\columnwidth]{fig_grpo.pdf}
304	  \caption{Post-RL trajectory for Qwen contaminated at 15\% on MMLU. Left axis: accuracy on seen (solid) and unseen (dashed) items. Right axis: $\ell_z^*$ seen-unseen gap (green diamonds). GRPO erases the accuracy gap ($11.4\text{pp} \to 2.1\text{pp}$) while the response-pattern gap persists (${\sim}3.3$). $N{=}1$, single model and RL method; no statistical inference is drawn.}
305	  \label{fig:grpo}
306	\end{figure}
307	
308	\section{QLoRA Training Hyperparameters}
309	\label{app:hyperparams}
310	
311	Table~\ref{tab:hyperparams} reports the QLoRA fine-tuning hyperparameters used across all experiments.
312	
313	\begin{table}[t]
314	\centering
315	\caption{QLoRA fine-tuning hyperparameters (shared across all model families and contamination conditions).}
316	\label{tab:hyperparams}
317	\footnotesize
318	\resizebox{\columnwidth}{!}{%
319	\begin{tabular}{@{}ll@{}}
320	\toprule
321	Hyperparameter & Value \\
322	\midrule
323	Quantization & 4-bit NF4 \\
324	LoRA rank & 16 \\
325	LoRA $\alpha$ & 32 \\
326	LoRA dropout & 0.05 \\
327	Target modules & \texttt{q\_proj}, \texttt{k\_proj}, \texttt{v\_proj}, \texttt{o\_proj} \\
328	Learning rate & $2 \times 10^{-4}$ \\
329	Optimizer & AdamW \\
330	Warmup ratio & 0.1 \\
331	Epochs & 3 \\
332	Per-device batch size & 4 \\
333	Gradient accumulation steps & 4 \\
334	Effective batch size & 16 \\
335	Max sequence length & 512 \\
336	Data mixing & Contaminated items shuffled into training set \\
337	\bottomrule
338	\end{tabular}}
339	\end{table}
340	
341	\section{Contamination Run Reproducibility}\label{app:reproducibility}
342	
343	\begin{table}[h]
344	\centering
345	\caption{Reproducibility of contamination effect sizes across independent QLoRA runs (Qwen2.5-7B-Instruct, MMLU). Each row shows Cohen's $|d|$ from an independent training seed against the shared $n{=}10$ clean baseline ($\bar{\ell}_z^* = 8.68$, $s = 0.74$). All runs use identical hyperparameters; only the random seed differs.}
346	\footnotesize
347	\begin{tabular}{@{}lcccccc@{}}
348	\toprule
349	& \multicolumn{3}{c}{Free-$\theta$ $|d|$} & \multicolumn{3}{c}{Fixed-$\theta$ $|d|$} \\
350	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
351	Seed & 15\% & 25\% & 50\% & 15\% & 25\% & 50\% \\
352	\midrule
353	42 (original) & 6.57 & 8.22 & 1.90 & 4.77 & 4.96 & 14.52 \\
354	123 & 5.09 & 8.78 & 5.42 & 7.79 & 5.37 & 12.64 \\
355	456 & 4.41 & 5.31 & 7.91 & 7.99 & 7.34 & 9.80 \\
356	\addlinespace
357	Mean & 5.36 & 7.44 & 5.08 & 6.85 & 5.89 & 12.32 \\
358	SD & 1.10 & 1.86 & 3.02 & 1.80 & 1.27 & 2.38 \\
359	CV (\%) & 20.3 & 25.2 & 59.6 & 26.3 & 21.7 & 19.3 \\
360	\bottomrule
361	\end{tabular}
362	\vspace{0.5em}
363	
364	\noindent\textit{Note.} Fixed-$\theta$ estimation anchors $\hat{\theta}$ at the clean-baseline mean ($\theta{=}{-}0.102$), removing $\theta$-shift absorption. The 50\% free-$\theta$ column exhibits high CV (59.6\%), reflecting seed-dependent $\theta$-shift magnitude; fixed-$\theta$ reduces this to 19.3\%, confirming that cross-seed variability at high contamination is driven by ability-estimate instability rather than true signal variance.
365	\end{table}
366	
367	\begin{table}[h]
368	\centering
369	\caption{Multi-seed Cohen's $|d|$ for HT and accuracy $z$-score statistics (Qwen2.5-7B-Instruct, MMLU), computed using the chi-squared ratio HT statistic and bootstrap Cohen's $d$ (10{,}000 resamples). These supplement the $\ell_z^*$ values in Table~\ref{tab:degradation}.}
370	\label{tab:ht_acc_multiseed}
371	\footnotesize
372	\begin{tabular}{@{}lcccccc@{}}
373	\toprule
374	& \multicolumn{3}{c}{HT $|d|$} & \multicolumn{3}{c}{Acc.\ $z$ $|d|$} \\
375	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
376	Seed & 15\% & 25\% & 50\% & 15\% & 25\% & 50\% \\
377	\midrule
378	42 (original) & 7.26 & 8.90 & 1.66 & 42.3 & 49.8 & 68.7 \\
379	123 & 5.52 & 9.51 & 5.80 & 47.3 & 53.4 & 70.8 \\
380	456 & 4.72 & 5.10 & 8.41 & 45.4 & 51.3 & 70.4 \\
381	\addlinespace
382	Mean & 5.83 & 7.84 & 5.29 & 45.0 & 51.5 & 70.0 \\
383	SD & 1.30 & 2.39 & 3.41 & 2.5 & 1.8 & 1.1 \\
384	\bottomrule
385	\end{tabular}
386	\vspace{0.5em}
387	
388	\noindent\textit{Note.} HT exhibits high cross-seed variance at 50\% (SD${=}3.41$), mirroring the $\ell_z^*$ pattern: the non-monotonicity observed in seed 42 ($|d|{=}1.66$) does not generalize across seeds. Accuracy $z$-scores are highly stable (CV $< 6\%$) and monotonically increasing with contamination level.
389	\end{table}
390	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "3afb9a71-15bb-4d86-81dc-b686e6bd4373",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex",
      "content": "\\section{Simulation Validation}\n\\label{app:simulation}\n\nUnder the null (no contamination), bootstrap $\\ell_z^*$ tracks $\\mathcal{N}(0,1)$: mean bias 0.041 and standard deviation 1.003 on MMLU.\nKolmogorov--Smirnov rejection rates vary with benchmark size: 8.3\\% for MMLU and HellaSwag ($n > 10{,}000$), 50.0\\% for GSM8K ($n = 1{,}319$), 58.3\\% for ARC-C ($n = 295$), and 75.0\\% for HumanEval ($n = 164$).\n$\\ell_z^*$ is well-calibrated for benchmarks with $n \\geq 10{,}000$ items; smaller benchmarks show increasing finite-sample deviations from normality.\n\nTwo-sided testing eliminates the inverted-U artifact: MMLU achieves 97.8\\% power at 15\\% contamination and sustains ${>}$93\\% at all levels.\nPower scales with $\\sqrt{n}$, as predicted by the noncentrality parameter $\\delta \\propto \\sqrt{n}$.\nThe empirical power function, derived via Gauss--Hermite quadrature ($K=30$) over the ability distribution, achieves $R^2 = 0.957$ against simulated values, with approximate minimum benchmark size of $n \\geq 7{,}958$ items for 80\\% power at 15\\% contamination under MMLU item parameters.\n\n\\section{4PL vs.\\ 3PL Ablation Details}\n\\label{app:4pl_ablation}\n\nTable~\\ref{tab:4pl_3pl_power} reports detection power (proportion of 2{,}000 simulation replicates rejecting $H_0$ at $\\alpha{=}0.05$, two-sided) for 4PL and 3PL parameterizations across five benchmarks and seven contamination levels.\nThe 4PL model yields higher power than 3PL at every non-trivial contamination level on every benchmark.\nThe advantage is largest on MMLU and HellaSwag, where upper-asymptote ($d < 1$) violations are most prevalent, and smallest on ARC-Challenge and HumanEval, where limited item counts constrain power under both parameterizations.\n\nPower is non-monotonic at 75\\% contamination under 4PL on four of five benchmarks (e.g., MMLU: $.952 \\to .938$; GSM8K: $.846 \\to .802$).\nThis reflects the $\\theta$-shift boundary condition described in \\S\\ref{sec:inverted_u}: at high contamination fractions, re-estimated $\\hat{\\theta}$ absorbs part of the aberrance signal, reducing $|\\ell_z^*|$.\nAt 100\\% contamination, all items are seen and power reaches 1.000 trivially.\nThe 4PL advantage over 3PL depends on accurate estimation of the upper asymptote $d$; with estimation error exceeding ${\\sim}10\\%$, the effective model behavior approaches 3PL ($d{=}1$) and the power gain diminishes.\nPSN-IRT's large calibration sample ($12{+}$ models per item) typically yields $d$ standard errors well below this threshold.\n\n\\begin{table*}[t]\n\\centering\n\\caption{Detection power (proportion rejecting $H_0$ at $\\alpha{=}0.05$) under 4PL and 3PL parameterizations across benchmarks and contamination levels ($n{=}2{,}000$ replicates per cell). Bold indicates the 4PL advantage exceeds 5\\,pp.}\n\\label{tab:4pl_3pl_power}\n\\small\n\\begin{tabular}{@{}llccccccc@{}}\n\\toprule\nBenchmark & IRT & 5\\% & 10\\% & 15\\% & 25\\% & 50\\% & 75\\% & 100\\% \\\\\n\\midrule\nMMLU & 4PL & \\textbf{.476} & \\textbf{.848} & \\textbf{.969} & \\textbf{.983} & \\textbf{.952} & \\textbf{.938} & 1.00 \\\\\n     & 3PL & .227 & .340 & .412 & .521 & .676 & .770 & 1.00 \\\\\n\\addlinespace\nHellaSwag & 4PL & \\textbf{.251} & \\textbf{.454} & \\textbf{.656} & \\textbf{.915} & \\textbf{.939} & \\textbf{.919} & 1.00 \\\\\n          & 3PL & .167 & .241 & .313 & .368 & .508 & .642 & 1.00 \\\\\n\\addlinespace\nGSM8K & 4PL & \\textbf{.156} & \\textbf{.309} & \\textbf{.492} & \\textbf{.737} & \\textbf{.846} & \\textbf{.802} & 1.00 \\\\\n      & 3PL & .102 & .172 & .285 & .396 & .567 & .577 & 1.00 \\\\\n\\addlinespace\nARC-C & 4PL & .057 & .075 & .087 & \\textbf{.130} & \\textbf{.285} & \\textbf{.493} & 1.00 \\\\\n      & 3PL & .054 & .062 & .071 & .076 & .110 & .102 & 1.00 \\\\\n\\addlinespace\nHumanEval & 4PL & .076 & .121 & \\textbf{.197} & \\textbf{.302} & \\textbf{.554} & \\textbf{.521} & 1.00 \\\\\n          & 3PL & .063 & .086 & .120 & .182 & .281 & .315 & 1.00 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\section{Seed Sensitivity Analysis}\n\\label{app:seed_sensitivity}\n\n\\paragraph{Clean-baseline variability.}\nTable~\\ref{tab:seed_sensitivity} reports $\\ell_z^*$, accuracy, and $\\hat{\\theta}_{\\text{MLE}}$ across three independent QLoRA runs (seeds 42, 123, 456).\nFor Qwen2.5-7B, $\\ell_z^*$ ranges from $7.05$ (seed 123) to $9.53$ (seed 456); the lower value of seed 123 likely reflects seed-specific training dynamics (random initialization, data ordering), but all three seeds produce $\\ell_z^* \\gg 1.96$, confirming that the elevated baseline reflects systematic model--benchmark misfit rather than seed-specific artifacts.\nLlama-3.1-8B shows $\\ell_z^*$ near zero ($-0.14 \\pm 0.97$), consistent with lower baseline misfit.\nAccuracy variability is negligible for both families (CV $< 0.004$).\n\n\\begin{table}[t]\n\\centering\n\\caption{Seed sensitivity analysis for clean baseline across three independent runs (seeds 42, 123, 456). CV = coefficient of variation ($\\mathrm{std}/|\\mathrm{mean}|$). These $n{=}3$ pilot results are superseded by the $n{=}10$ analysis in \\S\\ref{sec:detection}; retained for methodological transparency.}\n\\label{tab:seed_sensitivity}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\nModel & Metric & Mean & Std & Range & CV \\\\\n\\midrule\nQwen2.5-7B & $\\ell_z^*$ & 8.684 & 1.412 & 2.475 & 0.163 \\\\\n & Accuracy & 0.679 & 0.000 & 0.001 & 0.001 \\\\\n & $\\hat{\\theta}_{\\mathrm{MLE}}$ & $-$0.097 & 0.012 & 0.023 & 0.119 \\\\\n\\midrule\nLlama-3.1-8B & $\\ell_z^*$ & $-$0.141 & 0.965 & 1.929 & 6.860 \\\\\n & Accuracy & 0.594 & 0.002 & 0.004 & 0.004 \\\\\n & $\\hat{\\theta}_{\\mathrm{MLE}}$ & $-$0.645 & 0.019 & 0.036 & 0.029 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Cohen's $d$ confidence intervals.}\nTable~\\ref{tab:cohens_d_ci} reports Cohen's $d$ effect sizes with both analytic and bootstrap 95\\% confidence intervals.\nAnalytic CIs use $d \\pm t_{0.025,\\,\\text{df}=2} \\cdot \\text{SE}_d$; with only $n{=}3$ clean seeds (df${=}2$), the critical value $t_{0.025,2} = 4.303$ produces intervals wide enough to cross zero in all four conditions.\nThis is a known limitation of small-sample $t$-based intervals rather than evidence of null effects.\nBootstrap CIs (10{,}000 resamples with replacement from the three clean seeds) provide a nonparametric alternative: all four bootstrap intervals exclude zero, supporting the conclusion that contamination produces a reliably detectable signal despite the small reference sample.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cohen's $d$ with 95\\% confidence intervals for contaminated conditions relative to clean baselines ($n{=}3$ seeds). Analytic CIs use $t_{0.025, \\text{df}=2}$; bootstrap CIs use 10{,}000 resamples. These $n{=}3$ pilot results are superseded by the $n{=}10$ analysis in \\S\\ref{sec:detection}; retained for methodological transparency.}\n\\label{tab:cohens_d_ci}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llccc@{}}\n\\toprule\nModel & Cond. & $d$ & Analytic CI & Bootstrap CI \\\\\n\\midrule\nQwen & 15\\% & $-$3.42 & [$-$9.92, 3.08] & [$-$3.45, $-$2.82] \\\\\n & 50\\% & $-$0.99 & [$-$4.02, 2.04] & [$-$0.99, $-$0.41] \\\\\n\\midrule\nLlama & 15\\% & $-$2.95 & [$-$8.70, 2.80] & [$-$5.89, $-$2.29] \\\\\n & 50\\% & $-$3.31 & [$-$9.63, 3.01] & [$-$6.47, $-$2.59] \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Cross-family consistency.}\nTable~\\ref{tab:cross_family} confirms that both model families produce large negative Cohen's $d$ under contamination.\nThe $|\\Delta d| = 2.32$ gap at 50\\% contamination reflects Qwen's non-monotonic dose-response (the $\\theta$-shift boundary condition; \\S\\ref{sec:inverted_u}), not a failure of detection robustness---both families remain well above conventional large-effect thresholds ($|d| > 0.8$) at both contamination levels.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-family consistency of contamination detection ($n{=}3$ pilot). Both families show large negative $d$ under contamination. Superseded by $n{=}10$ results in \\S\\ref{sec:detection}; retained for methodological transparency.}\n\\label{tab:cross_family}\n\\small\n\\begin{tabular}{@{}lcccl@{}}\n\\toprule\nCondition & Qwen $d$ & Llama $d$ & $|\\Delta d|$ & Consistent? \\\\\n\\midrule\n15\\% contam. & $-$3.42 & $-$2.95 & 0.47 & Yes \\\\\n50\\% contam. & $-$0.99 & $-$3.31 & 2.32 & Yes \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Baseline $\\ell_z^*$ Interpretation}\n\\label{app:baseline_meaning}\n\nThe baseline $\\ell_z^*$ value reflects a model's difficulty-ordering consistency under the 4PL model, not its accuracy alone.\nIn the empirical data, Mistral ($\\text{acc}{=}0.514$, lowest among the 12 models) exhibits $\\ell_z^*{=}{+}5.42$ (second highest), because its response pattern follows the IRT-predicted difficulty ordering more closely than higher-accuracy models whose responses violate the assumed item structure.\nThis dissociation explains why Mistral produces the strongest contamination signal despite the lowest accuracy: its lower baseline ability ($\\hat{\\theta}{=}{-}1.16$) provides greater $\\theta$-shift headroom.\n\n\\section{Item-Level Detection Results}\n\\label{app:item_auroc}\n\nTable~\\ref{tab:item_auroc} reports item-level contamination detection performance at 15\\% contamination on MMLU.\nAll methods perform near random (AUROC $\\leq 0.63$), confirming that contamination is diffuse across the response pattern and that model-level aggregation via $\\ell_z^*$ is essential.\n\nAn accuracy $z$-score baseline yields $z{=}160$ at 15\\% contamination, but this reflects near-zero cross-seed accuracy variance ($\\text{std}{=}0.0003$), not genuine discriminability.\nIn deployment, accuracy variability from prompt format, evaluation harness, and hardware differences inflates the denominator, collapsing the $z$-score.\n\n\\begin{table}[t]\n\\centering\n\\caption{Item-level contamination detection (AUROC) at 15\\% contamination on MMLU.}\n\\label{tab:item_auroc}\n\\footnotesize\n\\begin{tabular}{@{}lc@{}}\n\\toprule\nMethod & AUROC \\\\\n\\midrule\nRandom baseline & 0.50 \\\\\n$\\ell_z^*$ itemwise & 0.53 \\\\\nLR cross-model & 0.59 \\\\\nRF cross-model & 0.63 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Robustness Analysis}\n\\label{app:robustness}\n\n\\subsection{$\\Delta\\ell_z^*$ Under Local Dependence}\n\\label{app:local_dep}\n\nIRT person-fit statistics assume local independence---conditional on $\\theta$, item responses are independent.\nLLM benchmarks violate this assumption through topical clustering (e.g., MMLU subjects); resampling-based approaches can provide valid person-fit assessment even under such violations \\citep{sinharay2016}.\nWe evaluate whether the $\\Delta\\ell_z^*$ matched-difference design is robust to local dependence (LD) via two simulation scenarios on 14,042 MMLU items with 1,000 replications each.\n\n\\paragraph{Shared LD.}\nClean and contaminated conditions share identical testlet structure (${\\sim}200$ testlets of ${\\sim}70$ items, random effect $\\gamma_t \\sim \\mathcal{N}(0, \\sigma_\\tau)$).\nTable~\\ref{tab:ld_shared} reports absolute $\\ell_z^*$ Type~I error and the ratio of $\\Delta\\ell_z^*$ effect size ($d$) to the no-LD baseline.\nWhile absolute $\\ell_z^*$ Type~I error inflates severely under LD (0.043$\\to$0.939 at $\\sigma{=}1.0$), the $\\Delta\\ell_z^*$ design maintains detection power: $d_{\\text{ratio}} \\geq 0.93$ for $\\sigma_\\tau \\leq 0.5$ (realistic range), confirming that shared misfit is cancelled by the matched-difference design.\n\n\\begin{table}[t]\n\\centering\n\\caption{Robustness of $\\Delta\\ell_z^*$ to shared local dependence (1,000 replications, MMLU). $d_{\\text{ratio}}$: effect size relative to the $\\sigma_\\tau{=}0$ baseline.}\n\\label{tab:ld_shared}\n\\footnotesize\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n$\\sigma_\\tau$ & Abs.\\ $\\ell_z^*$ Type~I & $d_{\\text{ratio}}$ (15\\%) & $d_{\\text{ratio}}$ (50\\%) \\\\\n\\midrule\n0.0 & 0.043 & 1.000 & 1.000 \\\\\n0.3 & 0.110 & 1.002 & 1.038 \\\\\n0.5 & 0.454 & 0.934 & 1.028 \\\\\n1.0 & 0.939 & 0.705 & 1.061 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Asymmetric LD.}\nIn the second scenario, contaminated models' seen items share an additional memory factor ($\\gamma_{\\text{mem}} \\sim \\mathcal{N}(0, \\sigma_{\\text{mem}})$), simulating contamination-specific LD not present in clean conditions ($\\sigma_\\tau{=}0.5$ fixed).\nTable~\\ref{tab:ld_asym} shows that $\\Delta\\ell_z^*$ maintains ${\\geq}98.5\\%$ power across all conditions, even when contamination introduces asymmetric dependence among seen items.\n\n\\begin{table}[t]\n\\centering\n\\caption{$\\Delta\\ell_z^*$ detection under asymmetric local dependence ($\\sigma_\\tau{=}0.5$, contamination-specific memory factor $\\sigma_{\\text{mem}}$; 1,000 replications, MMLU).}\n\\label{tab:ld_asym}\n\\footnotesize\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n$\\sigma_{\\text{mem}}$ & Power (15\\%) & $d$ (15\\%) & Power (50\\%) & $d$ (50\\%) \\\\\n\\midrule\n0.5 & 0.987 & $-$2.107 & 0.991 & $-$2.337 \\\\\n1.0 & 0.993 & $-$2.104 & 0.985 & $-$1.587 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Sensitivity to Item Parameter Estimation Error}\n\\label{app:param_perturb}\n\nPSN-IRT item parameters carry estimation error from the calibration sample.\nWe evaluate detection sensitivity by adding joint noise to all four parameters: multiplicative perturbation $p' = p \\cdot (1 + \\mathcal{N}(0, \\sigma))$ for $a$, $c$, and $d$; additive perturbation $b' = b + \\sigma \\cdot \\mathcal{N}(0, 1)$ for difficulty.\nTables~\\ref{tab:param_noise_free} and \\ref{tab:param_noise_fixed} report results over 100 trials using Qwen MMLU response vectors.\n\nDetection of 15\\% contamination is robust to parameter noise under free-$\\theta$ (17.4\\% bias at $\\sigma{=}10\\%$, $|d|$ still ${>}5$; Table~\\ref{tab:param_noise_free}).\nThe 50\\% contamination condition under free-$\\theta$ is fragile---consistent with its already-weak signal due to $\\theta$-shift absorption (\\S\\ref{sec:inverted_u}).\n\nUnder $\\theta$-fixed estimation (Table~\\ref{tab:param_noise_fixed}), detection is highly robust: 10\\% perturbation produces ${<}4\\%$ bias in Cohen's $d$, with worst-case $|d| = 3.73$ (15\\% contamination) and $12.20$ (50\\%)---both far exceeding conventional thresholds.\nThis contrasts sharply with free-$\\theta$ estimation, where 50\\% contamination Cohen's $d$ collapses to near zero under 10\\% noise.\nThe complementarity is clear: conditions where free-$\\theta$ detection is fragile (high-baseline-accuracy models with $\\theta$-shift absorption) are precisely where $\\theta$-fixed anchoring provides the strongest and most noise-robust signal.\n\n\\begin{table}[t]\n\\centering\n\\caption{Sensitivity of detection to item parameter noise (100 trials, Qwen MMLU, free-$\\theta$). \\% bias relative to noise-free $d$.}\n\\label{tab:param_noise_free}\n\\footnotesize\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nNoise $\\sigma$ & $d$ (15\\%) & \\% bias & $d$ (50\\%) & \\% bias \\\\\n\\midrule\n0\\% & $-$6.575 & --- & $-$1.897 & --- \\\\\n5\\% & $-$6.010 & 8.6 & $-$0.925 & 51.2 \\\\\n10\\% & $-$5.433 & 17.4 & $-$0.014 & 99.3 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[t]\n\\centering\n\\caption{Sensitivity of detection to item parameter noise (100 trials, Qwen MMLU, $\\theta$-fixed). Worst-case $|d|$ over 100 trials in parentheses.}\n\\label{tab:param_noise_fixed}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nNoise $\\sigma$ & $d_{\\text{fixed}}$ (15\\%) & \\% bias & $d_{\\text{fixed}}$ (50\\%) & \\% bias \\\\\n\\midrule\n0\\% & 4.77 & --- & 14.52 & --- \\\\\n5\\% & 5.07 $\\pm$ 0.24 & 6.3 & 14.76 $\\pm$ 0.44 & 1.6 \\\\\n10\\% & 4.95 $\\pm$ 0.43 (3.73) & 3.7 & 14.45 $\\pm$ 0.85 (12.20) & 0.5 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\section{BCa Bootstrap Sensitivity Check}\n\\label{app:bca}\n\nAs a sensitivity check, we computed bias-corrected and accelerated (BCa) bootstrap confidence intervals for all Cohen's $d$ estimates.\nBCa CIs were uniformly narrower than the percentile CIs reported in the main text (mean reduction 22\\%), confirming that our reported intervals are conservative.\nThe single condition where BCa widens the zero-crossing set---Llama fixed-$\\theta$ at 50\\% contamination, BCa CI [$-$0.13, 2.21] vs.\\ percentile CI [0.17, 2.97]---is already characterized as ineffective in \\S\\ref{sec:theta_dynamics}.\n\n\\section{Classical IRT Refit from Leaderboard Data}\n\\label{app:mml_em}\n\nTo assess whether item parameters can be recovered without PSN-IRT's neural calibration, we applied classical MML-EM estimation (Gauss--Hermite quadrature, $Q{=}31$ nodes) to binary response data from $N{=}178$ models on the Open LLM Leaderboard v1.\nWith 14,042 MMLU items and an examinee-to-item ratio of $N{:}J = 0.013$---far below the $N{>}500$ typically required for stable 3PL estimation---discrimination parameters are severely under-determined.\n\nTable~\\ref{tab:mml_em} reports parameter correlations between MML-EM-fitted and PSN-IRT parameters.\nDifficulty shows moderate agreement ($r_b{=}0.663$), but discrimination is essentially unrecovered ($r_a{=}0.127$).\nUsing these MML-EM parameters produces miscalibrated $\\ell_z^*$ statistics (mean$\\,{=}\\,$11.2, expected ${\\approx}\\,$0), confirming that the refitted model does not capture the data-generating process.\nThis motivates the dependence on PSN-IRT's externally calibrated item bank (\\S\\ref{sec:framework}).\n\n\\begin{table}[t]\n\\centering\n\\caption{Parameter correlation between classical MML-EM refit ($N{=}178$ models) and PSN-IRT on MMLU ($n{=}10{,}558$ matched items).}\n\\label{tab:mml_em}\n\\footnotesize\n\\begin{tabular}{@{}llcc@{}}\n\\toprule\nModel & Parameter & Pearson $r$ & Spearman $\\rho$ \\\\\n\\midrule\n3PL & $a$ (discrim.) & 0.127 & 0.135 \\\\\n3PL & $b$ (difficulty) & 0.663 & 0.684 \\\\\n2PL & $a$ (discrim.) & $-$0.029 & 0.050 \\\\\n2PL & $b$ (difficulty) & 0.608 & 0.656 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Post-RL Preliminary Observation}\n\\label{app:post_rl}\n\n\\citet{wang2025fragility} show that all MIA-based detectors fail after RL post-training.\nIn a single-model pilot ($N{=}1$, Qwen, GRPO), we applied GRPO \\citep{shao2024} for 1,500 steps to a contaminated model (15\\% MMLU) and evaluated at three checkpoints.\nGRPO erases the accuracy gap between seen and unseen items ($11.4\\text{pp} \\to 2.1\\text{pp}$), but the $\\ell_z^*$ response-pattern gap persists (${\\sim}3.3$; Figure~\\ref{fig:grpo}), suggesting structural traces of contamination may survive RL alignment.\nMin-K\\% membership inference confirms this dissociation: while SFT yields a weak MIA signal (AUC-ROC${=}0.611$), GRPO training drives AUC to $0.493$ (step~500), $0.493$ (step~1000), and $0.493$ (step~1500)---indistinguishable from random chance ($0.50$) as RL erases memorization-based features while the response-pattern anomaly that $\\ell_z^*$ detects persists.\nThis $N{=}1$ observation requires validation across model families, RL methods, and contamination levels before any conclusions can be drawn.\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_grpo.pdf}\n  \\caption{Post-RL trajectory for Qwen contaminated at 15\\% on MMLU. Left axis: accuracy on seen (solid) and unseen (dashed) items. Right axis: $\\ell_z^*$ seen-unseen gap (green diamonds). GRPO erases the accuracy gap ($11.4\\text{pp} \\to 2.1\\text{pp}$) while the response-pattern gap persists (${\\sim}3.3$). $N{=}1$, single model and RL method; no statistical inference is drawn.}\n  \\label{fig:grpo}\n\\end{figure}\n\n\\section{QLoRA Training Hyperparameters}\n\\label{app:hyperparams}\n\nTable~\\ref{tab:hyperparams} reports the QLoRA fine-tuning hyperparameters used across all experiments.\n\n\\begin{table}[t]\n\\centering\n\\caption{QLoRA fine-tuning hyperparameters (shared across all model families and contamination conditions).}\n\\label{tab:hyperparams}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}ll@{}}\n\\toprule\nHyperparameter & Value \\\\\n\\midrule\nQuantization & 4-bit NF4 \\\\\nLoRA rank & 16 \\\\\nLoRA $\\alpha$ & 32 \\\\\nLoRA dropout & 0.05 \\\\\nTarget modules & \\texttt{q\\_proj}, \\texttt{k\\_proj}, \\texttt{v\\_proj}, \\texttt{o\\_proj} \\\\\nLearning rate & $2 \\times 10^{-4}$ \\\\\nOptimizer & AdamW \\\\\nWarmup ratio & 0.1 \\\\\nEpochs & 3 \\\\\nPer-device batch size & 4 \\\\\nGradient accumulation steps & 4 \\\\\nEffective batch size & 16 \\\\\nMax sequence length & 512 \\\\\nData mixing & Contaminated items shuffled into training set \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\section{Contamination Run Reproducibility}\\label{app:reproducibility}\n\n\\begin{table}[h]\n\\centering\n\\caption{Reproducibility of contamination effect sizes across independent QLoRA runs (Qwen2.5-7B-Instruct, MMLU). Each row shows Cohen's $|d|$ from an independent training seed against the shared $n{=}10$ clean baseline ($\\bar{\\ell}_z^* = 8.68$, $s = 0.74$). All runs use identical hyperparameters; only the random seed differs.}\n\\footnotesize\n\\begin{tabular}{@{}lcccccc@{}}\n\\toprule\n& \\multicolumn{3}{c}{Free-$\\theta$ $|d|$} & \\multicolumn{3}{c}{Fixed-$\\theta$ $|d|$} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\nSeed & 15\\% & 25\\% & 50\\% & 15\\% & 25\\% & 50\\% \\\\\n\\midrule\n42 (original) & 6.57 & 8.22 & 1.90 & 4.77 & 4.96 & 14.52 \\\\\n123 & 5.09 & 8.78 & 5.42 & 7.79 & 5.37 & 12.64 \\\\\n456 & 4.41 & 5.31 & 7.91 & 7.99 & 7.34 & 9.80 \\\\\n\\addlinespace\nMean & 5.36 & 7.44 & 5.08 & 6.85 & 5.89 & 12.32 \\\\\nSD & 1.10 & 1.86 & 3.02 & 1.80 & 1.27 & 2.38 \\\\\nCV (\\%) & 20.3 & 25.2 & 59.6 & 26.3 & 21.7 & 19.3 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{0.5em}\n\n\\noindent\\textit{Note.} Fixed-$\\theta$ estimation anchors $\\hat{\\theta}$ at the clean-baseline mean ($\\theta{=}{-}0.102$), removing $\\theta$-shift absorption. The 50\\% free-$\\theta$ column exhibits high CV (59.6\\%), reflecting seed-dependent $\\theta$-shift magnitude; fixed-$\\theta$ reduces this to 19.3\\%, confirming that cross-seed variability at high contamination is driven by ability-estimate instability rather than true signal variance.\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\caption{Multi-seed Cohen's $|d|$ for HT and accuracy $z$-score statistics (Qwen2.5-7B-Instruct, MMLU), computed using the chi-squared ratio HT statistic and bootstrap Cohen's $d$ (10{,}000 resamples). These supplement the $\\ell_z^*$ values in Table~\\ref{tab:degradation}.}\n\\label{tab:ht_acc_multiseed}\n\\footnotesize\n\\begin{tabular}{@{}lcccccc@{}}\n\\toprule\n& \\multicolumn{3}{c}{HT $|d|$} & \\multicolumn{3}{c}{Acc.\\ $z$ $|d|$} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\nSeed & 15\\% & 25\\% & 50\\% & 15\\% & 25\\% & 50\\% \\\\\n\\midrule\n42 (original) & 7.26 & 8.90 & 1.66 & 42.3 & 49.8 & 68.7 \\\\\n123 & 5.52 & 9.51 & 5.80 & 47.3 & 53.4 & 70.8 \\\\\n456 & 4.72 & 5.10 & 8.41 & 45.4 & 51.3 & 70.4 \\\\\n\\addlinespace\nMean & 5.83 & 7.84 & 5.29 & 45.0 & 51.5 & 70.0 \\\\\nSD & 1.30 & 2.39 & 3.41 & 2.5 & 1.8 & 1.1 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{0.5em}\n\n\\noindent\\textit{Note.} HT exhibits high cross-seed variance at 50\\% (SD${=}3.41$), mirroring the $\\ell_z^*$ pattern: the non-monotonicity observed in seed 42 ($|d|{=}1.66$) does not generalize across seeds. Accuracy $z$-scores are highly stable (CV $< 6\\%$) and monotonically increasing with contamination level.\n\\end{table}\n",
      "numLines": 390,
      "startLine": 1,
      "totalLines": 390
    }
  }
}
```

</details>

---

### Tool call

_source line 18_

<details open><summary>🔧 Tool call — Read · `toolu_01JTCRUeHMbQUymx5QFSzaaz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "d7124556-5b27-483f-9f66-6af882d092b5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KvNyRMRnYCXyZe3QhH9Tg1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 256,
      "cache_read_input_tokens": 25077,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 256
      },
      "output_tokens": 65,
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

_source line 19 · 2026-05-23T04:16:10.091Z_

<details><summary>↩ Tool result · `toolu_01JTCRUeHMbQUymx5QFSzaaz`</summary>

```text
1	\section{Results}
2	\label{sec:results}
3	
4	\subsection{Detection Signal Across Model Families}
5	\label{sec:detection}
6	
7	Table~\ref{tab:cohens_d} presents Cohen's $d$ effect sizes for $\ell_z^*$ across three model families and two benchmarks.
8	All confidence intervals exclude zero, confirming that $\Delta\ell_z^*$ reliably separates contaminated from clean models at both contamination levels.
9	
10	On MMLU, effect sizes range from $|d|{=}2.27$ (Llama at 15\%) to $|d|{=}7.44$ (Qwen at 25\%), with Qwen at 5\% ($|d|{=}4.15$) confirming detection at the lowest contamination level tested. Llama ($|d|{=}2.27$/$2.97$/$2.50$) and Mistral ($|d|{=}3.01$/$3.50$) show comparable magnitudes.
11	On ARC-C (295 items), Qwen yields $|d|{=}3.16$ at 15\% and $|d|{=}5.30$ at 50\%, demonstrating that detection remains feasible even on small benchmarks when contamination is sufficiently concentrated.
12	
13	Clean-model $\ell_z^*$ baselines diverge substantially across families: Qwen ${+}8.68$ ($\text{SD}{=}0.74$), Mistral ${+}4.02$ ($\text{SD}{=}2.05$), Llama ${+}0.29$ ($\text{SD}{=}1.45$), and ARC-C Qwen ${-}5.42$ ($\text{SD}{=}0.16$).
14	Absolute $\ell_z^*$ thresholds would produce contradictory results: Qwen's contaminated $\ell_z^*$ at 15\% (${+}3.85$) is still positive.
15	The $\Delta\ell_z^*$ design normalizes these divergent baselines: Cohen's $d$ yields comparable effect sizes ($|d|{=}2.27$--$7.44$) despite order-of-magnitude differences.
16	Figure~\ref{fig:heatmap} provides a visual summary.
17	
18	\begin{table}[t]
19	\centering
20	\caption{Cohen's $d$ for $\Delta\ell_z^*$ across model families ($n{=}10$ clean seeds). Single-seed conditions: percentile bootstrap 95\% CI (10,000 resamples) reflecting clean-seed variability. Qwen MMLU 15\%/25\%/50\%: multi-seed mean $\pm$ SD ($n{=}3$ independent contamination runs). All exclude zero.}
21	\label{tab:cohens_d}
22	\footnotesize
23	\resizebox{\columnwidth}{!}{%
24	\begin{tabular}{@{}llrrrr@{}}
25	\toprule
26	Model & Bench. & $d$ (5\%) [CI] & $d$ (15\%) [CI] & $d$ (25\%) [CI] & $d$ (50\%) [CI] \\
27	\midrule
28	Qwen$^{\dagger}$ & MMLU & $-4.15$ [$-9.9$, $-2.7$] & $-5.36$ ($\pm$1.10) & $-7.44$ ($\pm$1.86) & $-5.08$ ($\pm$3.02) \\
29	Llama & MMLU & --- & $-2.27$ [$-4.6$, $-1.6$] & $-2.97$ [$-6.1$, $-2.0$] & $-2.50$ [$-5.0$, $-1.8$] \\
30	Mistral & MMLU & --- & $-3.01$ [$-8.2$, $-1.8$] & --- & $-3.50$ [$-9.4$, $-2.1$] \\
31	Qwen$^{\dagger}$ & ARC-C & --- & $+3.16$ [$2.0$, $9.5$] & --- & $+5.30$ [$3.6$, $15.2$] \\
32	\bottomrule
33	\multicolumn{6}{@{}l}{\scriptsize $^{\dagger}$15\%/25\%/50\%: multi-seed means ($n{=}3$ QLoRA runs); 5\%: single seed. Per-seed values in Appendix~\ref{app:reproducibility}.}
34	\end{tabular}}
35	\end{table}
36	
37	\begin{figure*}[t]
38	  \centering
39	  \includegraphics[width=\textwidth]{fig_heatmap.pdf}
40	  \caption{Cohen's $|d|$ heatmap (single-seed values; multi-seed means in Table~\ref{tab:cohens_d}). Blue intensity reflects effect-size magnitude. Grey cells: conditions not tested.}
41	  \label{fig:heatmap}
42	\end{figure*}
43	
44	\subsection{Model-Specific $\theta$-Shift Dynamics}
45	\label{sec:theta_dynamics}
46	
47	Contamination raises overall accuracy, which inflates $\hat{\theta}_{\text{MLE}}$; a higher $\hat{\theta}$ ``explains away'' anomalous successes on hard items, absorbing the contamination signal into the ability estimate.
48	We term this \emph{$\theta$-shift absorption}.
49	The magnitude of $\theta$-shift absorption varies across models: Qwen ($\Delta\theta{=}0.47$ at 50\%) absorbs substantially more signal than Llama ($\Delta\theta{=}0.09$), predicting that fixed-$\theta$ estimation should differentially amplify detection for high-absorption models.
50	Figure~\ref{fig:theta_scatter} plots baseline accuracy against Cohen's $|d|$ for all model-benchmark combinations.
51	
52	$\theta$-shift absorption is the dominant source of detection variability for high-ability models at high contamination:
53	(i) fixed-$\theta$ estimation amplifies Qwen's multi-seed $|d|$ by 2.4$\times$ at 50\% ($5.08 \to 12.32$; Table~\ref{tab:theta_fixed}), while Llama shows no amplification ($0.3\times$);
54	(ii) $\theta$-anchoring reduces Qwen's inter-seed CV from 60\% to 19\%, confirming that training-run variance is driven by $\theta$-shift stochasticity rather than true signal variance;
55	(iii) the cross-model ranking under free-$\theta$ is seed-dependent at 50\%, making $\theta$-anchoring a necessary condition for reliable detection of high-ability models at high contamination.
56	
57	ARC-C reverses this pattern.
58	Despite Qwen's high baseline accuracy on ARC-C (90.0\%), contamination produces larger, not smaller, effect sizes ($|d|{=}3.16$ at 15\%, $|d|{=}5.30$ at 50\%).
59	This reversal reflects a ceiling effect: with only 295 items and 90.0\% baseline accuracy, the already-correct items offer minimal room for further $\theta$ inflation, so contamination manifests primarily as anomalous successes on the few remaining hard items.
60	The small item count amplifies this concentration, producing a disproportionately large $\ell_z^*$ shift per contaminated item.
61	
62	The baseline $\ell_z^*$ for ARC-C is negative ($-5.42$), reflecting the 4PL model's expectation of near-perfect performance; contamination pushes $\ell_z^*$ toward zero, producing the positive Cohen's $d$ values in Table~\ref{tab:cohens_d}.
63	
64	These findings indicate that detection sensitivity is not a fixed property of $\ell_z^*$ but depends on the interaction between model ability and benchmark characteristics, a consideration absent from standard person-fit applications.
65	
66	\paragraph{Fixed-$\theta$ estimation.}
67	Table~\ref{tab:theta_fixed} compares free-$\theta$ and fixed-$\theta$ Cohen's $d$ across all three families.
68	The benefit of fixed-$\theta$ is strongly modulated by baseline ability and $\theta$-shift magnitude.
69	Qwen (67.8\% accuracy, $\Delta\theta{=}0.47$) shows the largest multi-seed amplification (2.4$\times$ at 50\%), because the high baseline provides substantial $\theta$-shift headroom that free estimation exploits.
70	Mistral (52.4\%) shows moderate amplification (1.7$\times$ at 50\%).
71	Llama (59.4\%) shows no benefit: its high cross-seed $\ell_z^*$ variance ($\text{SD}{=}1.45$) inflates the denominator, and its minimal $\theta$-shift ($\Delta\theta{=}0.09$) leaves little absorption to eliminate.
72	Fixed-$\theta$ is thus indicated for models with stable clean baselines and substantial $\theta$-shift ($\Delta\theta > 0.2$), not as a universal remedy.
73	
74	\begin{table}[t]
75	\centering
76	\caption{Free-$\theta$ vs.\ fixed-$\theta$ Cohen's $|d|$ on MMLU (bootstrap 95\% CI). Fixed-$\theta$ anchors $\hat{\theta}$ at the clean-model mean, eliminating $\theta$-shift absorption.}
77	\label{tab:theta_fixed}
78	\footnotesize
79	\begin{tabular}{@{}lcccc@{}}
80	\toprule
81	Model & $|d_{\text{free}}|$ & $|d_{\text{fixed}}|$ & Ratio & Fixed CI \\
82	\midrule
83	\multicolumn{5}{@{}l}{\textit{5\% contamination}} \\
84	Qwen & 4.15 & 3.52 & 0.8$\times$ & [2.9, 5.7] \\
85	\addlinespace
86	\multicolumn{5}{@{}l}{\textit{15\% contamination}} \\
87	Qwen$^{\S}$ & 5.36 & 6.85 & 1.3$\times$ & ($\pm$1.80) \\
88	Llama & 2.27 & 0.58 & 0.3$\times$ & [0, 2.37]$^{\dagger}$ \\
89	Mistral$^{\ddagger}$ & 3.01 & 2.69 & 0.9$\times$ & [1.45, 9.00] \\
90	\addlinespace
91	\multicolumn{5}{@{}l}{\textit{50\% contamination}} \\
92	Qwen$^{\S}$ & 5.08 & 12.32 & 2.4$\times$ & ($\pm$2.38) \\
93	Llama & 2.50 & 0.84 & 0.3$\times$ & [0.17, 2.97] \\
94	Mistral$^{\ddagger}$ & 3.50 & 5.80 & 1.7$\times$ & [3.71, 18.16] \\
95	\bottomrule
96	\multicolumn{5}{@{}l}{\scriptsize $^{\dagger}$CI includes zero.} \\
97	\multicolumn{5}{@{}l}{\scriptsize $^{\S}$Multi-seed mean ($n{=}3$); CI column shows $\pm$SD of fixed-$\theta$ $|d|$.} \\
98	\multicolumn{5}{@{}l}{\scriptsize $^{\ddagger}$Fixed-$\theta$: 6 seeds (4--7 response vectors not retained in pipeline); free-$\theta$ uses all 10.}
99	\end{tabular}
100	\end{table}
101	
102	\begin{figure}[t]
103	  \centering
104	  \includegraphics[width=\columnwidth]{fig_theta_scatter.pdf}
105	  \caption{Baseline accuracy vs.\ Cohen's $|d|$ for all model-benchmark combinations (single-seed values; multi-seed means in Table~\ref{tab:cohens_d}). Diamonds: 5\%; triangles: 15\%; squares: 25\%; circles: 50\%. ARC-C reversal reflects a ceiling effect.}
106	  \label{fig:theta_scatter}
107	\end{figure}
108	
109	\subsection{Detection-Diagnosis Tradeoff}
110	\label{sec:degradation}
111	
112	A natural question is whether the full 4PL IRT framework is necessary for contamination detection, or whether simpler statistics suffice.
113	Table~\ref{tab:degradation} compares three statistics at decreasing levels of information access: $\ell_z^*$ (requires 4PL parameters $a, b, c, d$), the HT statistic (requires only difficulty $b$), and an accuracy $z$-score (requires no item parameters).
114	
115	The comparison reveals a detection-diagnosis tradeoff.
116	For pure detection, simpler statistics are more powerful: accuracy $z$-scores yield $|d|$ values several-fold to over an order of magnitude larger than person-fit statistics (Table~\ref{tab:degradation}), because cross-seed accuracy variance is near-zero in controlled settings.
117	HT generally exceeds $\ell_z^*$ in detection strength, since HT is not attenuated by the Snijders correction for $\theta$ estimation uncertainty.
118	Both person-fit statistics exhibit seed-dependent non-monotonicity under free-$\theta$ estimation (Table~\ref{tab:degradation}), confirming that $\theta$-shift absorption affects all statistics conditioned on ability, not $\ell_z^*$ specifically.
119	
120	Yet the diagnostic power reverses.
121	Full IRT parameterization is unnecessary for mere detection, but the value of $\ell_z^*$ lies in three capabilities that HT and $z$-scores lack:
122	(a) \emph{seen/unseen decomposition}: $\ell_z^*$ can be computed separately on seen and unseen item subsets, though item-level detection is near-random (AUROC $\approx 0.53$; Appendix~\ref{app:item_auroc}), confirming that the contamination signal is diffuse and requires model-level aggregation;
123	(b) \emph{$\theta$-shift mechanism}: the ability parameter exposes why detection sensitivity depends on model ability (\S\ref{sec:theta_dynamics}), a mechanistic insight inaccessible to non-parametric statistics;
124	(c) \emph{structural sensitivity}: on real leaderboard data, $\ell_z^*$ flags 57/60 model-benchmark cells as aberrant---evidence of systematic IRT assumption violations that motivates the $\Delta\ell_z^*$ matched-difference design (\S\ref{sec:did}).
125	Accuracy $z$-scores flag only 4/60 cells, making them insensitive to the response-pattern structure that $\ell_z^*$ exploits for within-model diagnosis.
126	While such patterns have theoretical antecedents in person-fit literature \citep{stonge2011}, the specific magnitude and model-dependence we observe are new empirical findings in the LLM domain; nonparametric alternatives \citep{tendeiro2014} may complement $\ell_z^*$ where 4PL calibration is unavailable.
127	
128	In practice, a two-stage workflow follows: screen using accuracy $z$-scores (Table~\ref{tab:degradation}), then apply $\ell_z^*$ to characterize whether the signal reflects $\theta$-shift absorption (indicating fixed-$\theta$ anchoring is needed) or uniform aberrance (suggesting direct memorization).
129	
130	Within the IRT family, the 4PL specification matters: simulation ablations show a mean $+$27.3pp power gain over 3PL on MMLU, because 46\% of MMLU items have upper asymptote $d < 0.95$, and the 3PL model (which assumes $d{=}1$) misattributes slip-related response patterns as aberrance (Appendix~\ref{app:4pl_ablation}).
131	
132	\begin{table}[t]
133	\centering
134	\caption{Detection-diagnosis tradeoff on MMLU: Cohen's $|d|$ across three statistics. Simpler statistics detect more powerfully; $\ell_z^*$ provides unique diagnostic capabilities (\S\ref{sec:degradation}).}
135	\label{tab:degradation}
136	\footnotesize
137	\begin{tabular}{@{}llrr@{}}
138	\toprule
139	Model & Statistic & $|d|$ (15\%) & $|d|$ (50\%) \\
140	\midrule
141	Qwen$^\dagger$ & $\ell_z^*$ & $5.36$ ($\pm$1.10) & $5.08$ ($\pm$3.02) \\
142	     & HT & $5.83$ ($\pm$1.30) & $5.29$ ($\pm$3.41) \\
143	     & Acc.\ $z$ & $45.0$ ($\pm$2.5) & $70.0$ ($\pm$1.1) \\
144	\addlinespace
145	Llama & $\ell_z^*$ & $2.27$ [$1.6$, $4.6$] & $2.50$ [$1.8$, $5.2$] \\
146	      & HT & $2.45$ [$1.5$, $4.3$] & $3.07$ [$1.9$, $5.3$] \\
147	      & Acc.\ $z$ & $22.5$ [$13.6$, $47.0$] & $32.8$ [$19.8$, $68.6$] \\
148	\addlinespace
149	Mistral & $\ell_z^*$ & $3.01$ [$1.8$, $8.2$] & $3.50$ [$2.1$, $9.4$] \\
150	      & HT & $4.36$ [$1.2$, $7.0$] & $5.89$ [$1.9$, $9.4$] \\
151	      & Acc.\ $z$ & $7.81$ [$4.4$, $14.4$] & $16.6$ [$9.7$, $34.6$] \\
152	\bottomrule
153	\multicolumn{4}{@{}p{0.9\columnwidth}}{\scriptsize $^\dagger$Qwen values are means across $n{=}3$ independent seeds (42, 123, 456); per-seed values in Appendix~\ref{app:reproducibility}. Llama and Mistral are single-seed with bootstrap CIs.}
154	\end{tabular}
155	\end{table}
156	
157	\subsection{Ability-Dependent Non-Monotonic Dose-Response}
158	\label{sec:inverted_u}
159	
160	As an exploratory observation, the free-$\theta$ dose-response is non-monotonic for Qwen.
161	The multi-seed mean trajectory ($|d|$: $4.15 \to 5.36 \to 7.44 \to 5.08$ at 5\%/15\%/25\%/50\%; Appendix~\ref{app:reproducibility}) shows signal peaking at 25\% before declining at 50\%, but the decline is attenuated relative to single-seed estimates and the inter-seed variance at 50\% is high (CV${=}$60\%, range $[1.90, 7.91]$).
162	This non-monotonicity is a $\theta$-estimation artifact: fixed-$\theta$ analysis eliminates the inverted-U and reveals a strong positive dose-response (mean $|d|$: $5.89$ at 25\% vs.\ $12.32$ at 50\%, no seed-level overlap), while reducing the 50\% CV to 19\%.
163	Llama shows an attenuated, statistically non-significant pattern ($|d|{=}2.27 \to 2.97 \to 2.50$), consistent with its smaller $\theta$-shift ($\Delta\theta{=}0.09$ vs.\ $0.47$ for Qwen).
164	The mechanism is predictable from simulation (Appendix~\ref{app:simulation}): at moderate contamination, aberrant responses dominate; at high contamination, inflated $\hat{\theta}$ absorbs the anomaly---but the magnitude is highly seed-dependent.
165	
166	A simulated power analysis corroborates these findings: two-sided testing (flagging both large negative and large positive $\ell_z^*$) achieves ${>}$93\% power on MMLU at all contamination levels, with the theoretical power function yielding $R^2 {=} 0.957$ against simulated values (Appendix~\ref{app:simulation}).
167	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "2b9da178-26df-40e9-856b-0be8913eea53",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex",
      "content": "\\section{Results}\n\\label{sec:results}\n\n\\subsection{Detection Signal Across Model Families}\n\\label{sec:detection}\n\nTable~\\ref{tab:cohens_d} presents Cohen's $d$ effect sizes for $\\ell_z^*$ across three model families and two benchmarks.\nAll confidence intervals exclude zero, confirming that $\\Delta\\ell_z^*$ reliably separates contaminated from clean models at both contamination levels.\n\nOn MMLU, effect sizes range from $|d|{=}2.27$ (Llama at 15\\%) to $|d|{=}7.44$ (Qwen at 25\\%), with Qwen at 5\\% ($|d|{=}4.15$) confirming detection at the lowest contamination level tested. Llama ($|d|{=}2.27$/$2.97$/$2.50$) and Mistral ($|d|{=}3.01$/$3.50$) show comparable magnitudes.\nOn ARC-C (295 items), Qwen yields $|d|{=}3.16$ at 15\\% and $|d|{=}5.30$ at 50\\%, demonstrating that detection remains feasible even on small benchmarks when contamination is sufficiently concentrated.\n\nClean-model $\\ell_z^*$ baselines diverge substantially across families: Qwen ${+}8.68$ ($\\text{SD}{=}0.74$), Mistral ${+}4.02$ ($\\text{SD}{=}2.05$), Llama ${+}0.29$ ($\\text{SD}{=}1.45$), and ARC-C Qwen ${-}5.42$ ($\\text{SD}{=}0.16$).\nAbsolute $\\ell_z^*$ thresholds would produce contradictory results: Qwen's contaminated $\\ell_z^*$ at 15\\% (${+}3.85$) is still positive.\nThe $\\Delta\\ell_z^*$ design normalizes these divergent baselines: Cohen's $d$ yields comparable effect sizes ($|d|{=}2.27$--$7.44$) despite order-of-magnitude differences.\nFigure~\\ref{fig:heatmap} provides a visual summary.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cohen's $d$ for $\\Delta\\ell_z^*$ across model families ($n{=}10$ clean seeds). Single-seed conditions: percentile bootstrap 95\\% CI (10,000 resamples) reflecting clean-seed variability. Qwen MMLU 15\\%/25\\%/50\\%: multi-seed mean $\\pm$ SD ($n{=}3$ independent contamination runs). All exclude zero.}\n\\label{tab:cohens_d}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llrrrr@{}}\n\\toprule\nModel & Bench. & $d$ (5\\%) [CI] & $d$ (15\\%) [CI] & $d$ (25\\%) [CI] & $d$ (50\\%) [CI] \\\\\n\\midrule\nQwen$^{\\dagger}$ & MMLU & $-4.15$ [$-9.9$, $-2.7$] & $-5.36$ ($\\pm$1.10) & $-7.44$ ($\\pm$1.86) & $-5.08$ ($\\pm$3.02) \\\\\nLlama & MMLU & --- & $-2.27$ [$-4.6$, $-1.6$] & $-2.97$ [$-6.1$, $-2.0$] & $-2.50$ [$-5.0$, $-1.8$] \\\\\nMistral & MMLU & --- & $-3.01$ [$-8.2$, $-1.8$] & --- & $-3.50$ [$-9.4$, $-2.1$] \\\\\nQwen$^{\\dagger}$ & ARC-C & --- & $+3.16$ [$2.0$, $9.5$] & --- & $+5.30$ [$3.6$, $15.2$] \\\\\n\\bottomrule\n\\multicolumn{6}{@{}l}{\\scriptsize $^{\\dagger}$15\\%/25\\%/50\\%: multi-seed means ($n{=}3$ QLoRA runs); 5\\%: single seed. Per-seed values in Appendix~\\ref{app:reproducibility}.}\n\\end{tabular}}\n\\end{table}\n\n\\begin{figure*}[t]\n  \\centering\n  \\includegraphics[width=\\textwidth]{fig_heatmap.pdf}\n  \\caption{Cohen's $|d|$ heatmap (single-seed values; multi-seed means in Table~\\ref{tab:cohens_d}). Blue intensity reflects effect-size magnitude. Grey cells: conditions not tested.}\n  \\label{fig:heatmap}\n\\end{figure*}\n\n\\subsection{Model-Specific $\\theta$-Shift Dynamics}\n\\label{sec:theta_dynamics}\n\nContamination raises overall accuracy, which inflates $\\hat{\\theta}_{\\text{MLE}}$; a higher $\\hat{\\theta}$ ``explains away'' anomalous successes on hard items, absorbing the contamination signal into the ability estimate.\nWe term this \\emph{$\\theta$-shift absorption}.\nThe magnitude of $\\theta$-shift absorption varies across models: Qwen ($\\Delta\\theta{=}0.47$ at 50\\%) absorbs substantially more signal than Llama ($\\Delta\\theta{=}0.09$), predicting that fixed-$\\theta$ estimation should differentially amplify detection for high-absorption models.\nFigure~\\ref{fig:theta_scatter} plots baseline accuracy against Cohen's $|d|$ for all model-benchmark combinations.\n\n$\\theta$-shift absorption is the dominant source of detection variability for high-ability models at high contamination:\n(i) fixed-$\\theta$ estimation amplifies Qwen's multi-seed $|d|$ by 2.4$\\times$ at 50\\% ($5.08 \\to 12.32$; Table~\\ref{tab:theta_fixed}), while Llama shows no amplification ($0.3\\times$);\n(ii) $\\theta$-anchoring reduces Qwen's inter-seed CV from 60\\% to 19\\%, confirming that training-run variance is driven by $\\theta$-shift stochasticity rather than true signal variance;\n(iii) the cross-model ranking under free-$\\theta$ is seed-dependent at 50\\%, making $\\theta$-anchoring a necessary condition for reliable detection of high-ability models at high contamination.\n\nARC-C reverses this pattern.\nDespite Qwen's high baseline accuracy on ARC-C (90.0\\%), contamination produces larger, not smaller, effect sizes ($|d|{=}3.16$ at 15\\%, $|d|{=}5.30$ at 50\\%).\nThis reversal reflects a ceiling effect: with only 295 items and 90.0\\% baseline accuracy, the already-correct items offer minimal room for further $\\theta$ inflation, so contamination manifests primarily as anomalous successes on the few remaining hard items.\nThe small item count amplifies this concentration, producing a disproportionately large $\\ell_z^*$ shift per contaminated item.\n\nThe baseline $\\ell_z^*$ for ARC-C is negative ($-5.42$), reflecting the 4PL model's expectation of near-perfect performance; contamination pushes $\\ell_z^*$ toward zero, producing the positive Cohen's $d$ values in Table~\\ref{tab:cohens_d}.\n\nThese findings indicate that detection sensitivity is not a fixed property of $\\ell_z^*$ but depends on the interaction between model ability and benchmark characteristics, a consideration absent from standard person-fit applications.\n\n\\paragraph{Fixed-$\\theta$ estimation.}\nTable~\\ref{tab:theta_fixed} compares free-$\\theta$ and fixed-$\\theta$ Cohen's $d$ across all three families.\nThe benefit of fixed-$\\theta$ is strongly modulated by baseline ability and $\\theta$-shift magnitude.\nQwen (67.8\\% accuracy, $\\Delta\\theta{=}0.47$) shows the largest multi-seed amplification (2.4$\\times$ at 50\\%), because the high baseline provides substantial $\\theta$-shift headroom that free estimation exploits.\nMistral (52.4\\%) shows moderate amplification (1.7$\\times$ at 50\\%).\nLlama (59.4\\%) shows no benefit: its high cross-seed $\\ell_z^*$ variance ($\\text{SD}{=}1.45$) inflates the denominator, and its minimal $\\theta$-shift ($\\Delta\\theta{=}0.09$) leaves little absorption to eliminate.\nFixed-$\\theta$ is thus indicated for models with stable clean baselines and substantial $\\theta$-shift ($\\Delta\\theta > 0.2$), not as a universal remedy.\n\n\\begin{table}[t]\n\\centering\n\\caption{Free-$\\theta$ vs.\\ fixed-$\\theta$ Cohen's $|d|$ on MMLU (bootstrap 95\\% CI). Fixed-$\\theta$ anchors $\\hat{\\theta}$ at the clean-model mean, eliminating $\\theta$-shift absorption.}\n\\label{tab:theta_fixed}\n\\footnotesize\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nModel & $|d_{\\text{free}}|$ & $|d_{\\text{fixed}}|$ & Ratio & Fixed CI \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{5\\% contamination}} \\\\\nQwen & 4.15 & 3.52 & 0.8$\\times$ & [2.9, 5.7] \\\\\n\\addlinespace\n\\multicolumn{5}{@{}l}{\\textit{15\\% contamination}} \\\\\nQwen$^{\\S}$ & 5.36 & 6.85 & 1.3$\\times$ & ($\\pm$1.80) \\\\\nLlama & 2.27 & 0.58 & 0.3$\\times$ & [0, 2.37]$^{\\dagger}$ \\\\\nMistral$^{\\ddagger}$ & 3.01 & 2.69 & 0.9$\\times$ & [1.45, 9.00] \\\\\n\\addlinespace\n\\multicolumn{5}{@{}l}{\\textit{50\\% contamination}} \\\\\nQwen$^{\\S}$ & 5.08 & 12.32 & 2.4$\\times$ & ($\\pm$2.38) \\\\\nLlama & 2.50 & 0.84 & 0.3$\\times$ & [0.17, 2.97] \\\\\nMistral$^{\\ddagger}$ & 3.50 & 5.80 & 1.7$\\times$ & [3.71, 18.16] \\\\\n\\bottomrule\n\\multicolumn{5}{@{}l}{\\scriptsize $^{\\dagger}$CI includes zero.} \\\\\n\\multicolumn{5}{@{}l}{\\scriptsize $^{\\S}$Multi-seed mean ($n{=}3$); CI column shows $\\pm$SD of fixed-$\\theta$ $|d|$.} \\\\\n\\multicolumn{5}{@{}l}{\\scriptsize $^{\\ddagger}$Fixed-$\\theta$: 6 seeds (4--7 response vectors not retained in pipeline); free-$\\theta$ uses all 10.}\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_theta_scatter.pdf}\n  \\caption{Baseline accuracy vs.\\ Cohen's $|d|$ for all model-benchmark combinations (single-seed values; multi-seed means in Table~\\ref{tab:cohens_d}). Diamonds: 5\\%; triangles: 15\\%; squares: 25\\%; circles: 50\\%. ARC-C reversal reflects a ceiling effect.}\n  \\label{fig:theta_scatter}\n\\end{figure}\n\n\\subsection{Detection-Diagnosis Tradeoff}\n\\label{sec:degradation}\n\nA natural question is whether the full 4PL IRT framework is necessary for contamination detection, or whether simpler statistics suffice.\nTable~\\ref{tab:degradation} compares three statistics at decreasing levels of information access: $\\ell_z^*$ (requires 4PL parameters $a, b, c, d$), the HT statistic (requires only difficulty $b$), and an accuracy $z$-score (requires no item parameters).\n\nThe comparison reveals a detection-diagnosis tradeoff.\nFor pure detection, simpler statistics are more powerful: accuracy $z$-scores yield $|d|$ values several-fold to over an order of magnitude larger than person-fit statistics (Table~\\ref{tab:degradation}), because cross-seed accuracy variance is near-zero in controlled settings.\nHT generally exceeds $\\ell_z^*$ in detection strength, since HT is not attenuated by the Snijders correction for $\\theta$ estimation uncertainty.\nBoth person-fit statistics exhibit seed-dependent non-monotonicity under free-$\\theta$ estimation (Table~\\ref{tab:degradation}), confirming that $\\theta$-shift absorption affects all statistics conditioned on ability, not $\\ell_z^*$ specifically.\n\nYet the diagnostic power reverses.\nFull IRT parameterization is unnecessary for mere detection, but the value of $\\ell_z^*$ lies in three capabilities that HT and $z$-scores lack:\n(a) \\emph{seen/unseen decomposition}: $\\ell_z^*$ can be computed separately on seen and unseen item subsets, though item-level detection is near-random (AUROC $\\approx 0.53$; Appendix~\\ref{app:item_auroc}), confirming that the contamination signal is diffuse and requires model-level aggregation;\n(b) \\emph{$\\theta$-shift mechanism}: the ability parameter exposes why detection sensitivity depends on model ability (\\S\\ref{sec:theta_dynamics}), a mechanistic insight inaccessible to non-parametric statistics;\n(c) \\emph{structural sensitivity}: on real leaderboard data, $\\ell_z^*$ flags 57/60 model-benchmark cells as aberrant---evidence of systematic IRT assumption violations that motivates the $\\Delta\\ell_z^*$ matched-difference design (\\S\\ref{sec:did}).\nAccuracy $z$-scores flag only 4/60 cells, making them insensitive to the response-pattern structure that $\\ell_z^*$ exploits for within-model diagnosis.\nWhile such patterns have theoretical antecedents in person-fit literature \\citep{stonge2011}, the specific magnitude and model-dependence we observe are new empirical findings in the LLM domain; nonparametric alternatives \\citep{tendeiro2014} may complement $\\ell_z^*$ where 4PL calibration is unavailable.\n\nIn practice, a two-stage workflow follows: screen using accuracy $z$-scores (Table~\\ref{tab:degradation}), then apply $\\ell_z^*$ to characterize whether the signal reflects $\\theta$-shift absorption (indicating fixed-$\\theta$ anchoring is needed) or uniform aberrance (suggesting direct memorization).\n\nWithin the IRT family, the 4PL specification matters: simulation ablations show a mean $+$27.3pp power gain over 3PL on MMLU, because 46\\% of MMLU items have upper asymptote $d < 0.95$, and the 3PL model (which assumes $d{=}1$) misattributes slip-related response patterns as aberrance (Appendix~\\ref{app:4pl_ablation}).\n\n\\begin{table}[t]\n\\centering\n\\caption{Detection-diagnosis tradeoff on MMLU: Cohen's $|d|$ across three statistics. Simpler statistics detect more powerfully; $\\ell_z^*$ provides unique diagnostic capabilities (\\S\\ref{sec:degradation}).}\n\\label{tab:degradation}\n\\footnotesize\n\\begin{tabular}{@{}llrr@{}}\n\\toprule\nModel & Statistic & $|d|$ (15\\%) & $|d|$ (50\\%) \\\\\n\\midrule\nQwen$^\\dagger$ & $\\ell_z^*$ & $5.36$ ($\\pm$1.10) & $5.08$ ($\\pm$3.02) \\\\\n     & HT & $5.83$ ($\\pm$1.30) & $5.29$ ($\\pm$3.41) \\\\\n     & Acc.\\ $z$ & $45.0$ ($\\pm$2.5) & $70.0$ ($\\pm$1.1) \\\\\n\\addlinespace\nLlama & $\\ell_z^*$ & $2.27$ [$1.6$, $4.6$] & $2.50$ [$1.8$, $5.2$] \\\\\n      & HT & $2.45$ [$1.5$, $4.3$] & $3.07$ [$1.9$, $5.3$] \\\\\n      & Acc.\\ $z$ & $22.5$ [$13.6$, $47.0$] & $32.8$ [$19.8$, $68.6$] \\\\\n\\addlinespace\nMistral & $\\ell_z^*$ & $3.01$ [$1.8$, $8.2$] & $3.50$ [$2.1$, $9.4$] \\\\\n      & HT & $4.36$ [$1.2$, $7.0$] & $5.89$ [$1.9$, $9.4$] \\\\\n      & Acc.\\ $z$ & $7.81$ [$4.4$, $14.4$] & $16.6$ [$9.7$, $34.6$] \\\\\n\\bottomrule\n\\multicolumn{4}{@{}p{0.9\\columnwidth}}{\\scriptsize $^\\dagger$Qwen values are means across $n{=}3$ independent seeds (42, 123, 456); per-seed values in Appendix~\\ref{app:reproducibility}. Llama and Mistral are single-seed with bootstrap CIs.}\n\\end{tabular}\n\\end{table}\n\n\\subsection{Ability-Dependent Non-Monotonic Dose-Response}\n\\label{sec:inverted_u}\n\nAs an exploratory observation, the free-$\\theta$ dose-response is non-monotonic for Qwen.\nThe multi-seed mean trajectory ($|d|$: $4.15 \\to 5.36 \\to 7.44 \\to 5.08$ at 5\\%/15\\%/25\\%/50\\%; Appendix~\\ref{app:reproducibility}) shows signal peaking at 25\\% before declining at 50\\%, but the decline is attenuated relative to single-seed estimates and the inter-seed variance at 50\\% is high (CV${=}$60\\%, range $[1.90, 7.91]$).\nThis non-monotonicity is a $\\theta$-estimation artifact: fixed-$\\theta$ analysis eliminates the inverted-U and reveals a strong positive dose-response (mean $|d|$: $5.89$ at 25\\% vs.\\ $12.32$ at 50\\%, no seed-level overlap), while reducing the 50\\% CV to 19\\%.\nLlama shows an attenuated, statistically non-significant pattern ($|d|{=}2.27 \\to 2.97 \\to 2.50$), consistent with its smaller $\\theta$-shift ($\\Delta\\theta{=}0.09$ vs.\\ $0.47$ for Qwen).\nThe mechanism is predictable from simulation (Appendix~\\ref{app:simulation}): at moderate contamination, aberrant responses dominate; at high contamination, inflated $\\hat{\\theta}$ absorbs the anomaly---but the magnitude is highly seed-dependent.\n\nA simulated power analysis corroborates these findings: two-sided testing (flagging both large negative and large positive $\\ell_z^*$) achieves ${>}$93\\% power on MMLU at all contamination levels, with the theoretical power function yielding $R^2 {=} 0.957$ against simulated values (Appendix~\\ref{app:simulation}).\n",
      "numLines": 167,
      "startLine": 1,
      "totalLines": 167
    }
  }
}
```

</details>

---

### Tool call

_source line 20_

<details open><summary>🔧 Tool call — Read · `toolu_01TranV8kM3NarWCw6T9wMLV`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "2a731819-db81-42a6-9fed-c56927adb0fb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KvNyRMRnYCXyZe3QhH9Tg1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 256,
      "cache_read_input_tokens": 25077,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 256
      },
      "output_tokens": 65,
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

_source line 21 · 2026-05-23T04:16:10.568Z_

<details><summary>↩ Tool result · `toolu_01TranV8kM3NarWCw6T9wMLV`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{IRT Person-Fit Framework}
5	\label{sec:framework}
6	
7	We adopt the four-parameter logistic (4PL) IRT model to characterize contamination-induced aberrance in LLM response patterns.
8	The 4PL model defines the probability that a model with ability $\theta$ answers item $i$ correctly:
9	\begin{equation}
10	  P_i(\theta) = c_i + (d_i - c_i)\,\frac{1}{1 + e^{-a_i(\theta - b_i)}}
11	  \label{eq:4pl}
12	\end{equation}
13	where $a_i$ is discrimination, $b_i$ difficulty, $c_i$ the lower asymptote (guessing), and $d_i$ the upper asymptote (slip).
14	Item parameters are pre-calibrated by PSN-IRT \citep{psnirt2026} from a large-scale leaderboard dataset; we use these external parameters rather than re-estimating from potentially contaminated data, since our MML-EM refit shows discrimination recovery degrades to $r_a{=}0.127$ on contaminated leaderboard data.
15	
16	Given item parameters and a binary response vector $\mathbf{x} = (x_1, \ldots, x_n)$, we compute the person-fit statistic $\ell_z^*$ \citep{snijders2001}, a standardized log-likelihood residual quantifying deviation between observed and expected response patterns.
17	The Snijders correction accounts for estimation uncertainty in $\hat{\theta}_{\text{MLE}}$, so that $\ell_z^* \sim \mathcal{N}(0,1)$ under the null \citep{drasgow1985, snijders2001}; \citet{magis2012} provide a detailed treatment of how response model selection and ability estimation affect $\ell_z^*$.
18	Large negative $\ell_z^*$ indicates aberrant responding (unexpected failures on easy items or unexpected successes on hard items); large positive values indicate over-consistent patterns.
19	
20	\subsection{$\Delta\ell_z^*$ Matched-Difference Design}
21	\label{sec:did}
22	
23	LLM response patterns systematically violate IRT assumptions of local independence and unidimensionality.
24	In our empirical data, 57 of 60 model-benchmark cells yield $|\ell_z^*| > 1.96$ even absent contamination, rendering absolute thresholds uninformative.
25	We address this through a matched-difference design.
26	
27	For controlled experiments with clean baselines, we compute:
28	\begin{equation}
29	  \Delta\ell_z^* = \ell_{z,\text{contam}}^{*} - \bar{\ell}_{z,\text{clean}}^{*}
30	  \label{eq:delta_lz}
31	\end{equation}
32	where $\bar{\ell}_{z,\text{clean}}^{*}$ averages over $n{=}10$ clean seeds.
33	The shared model misfit cancels, isolating contamination-specific aberrance.
34	We quantify effect sizes as $d = (\ell_{z,\text{contam}}^{*} - \bar{\ell}_{z,\text{clean}}^{*})\,/\,s_{\text{clean}}$, where $s_{\text{clean}}$ is the SD of the $n{=}10$ clean-seed $\ell_z^*$ values; with a single contaminated observation per condition, $d$ is a standardized departure rather than a two-sample effect size (Hedges' $g = J \cdot d$, $J \approx 0.914$ for $n{=}10$; \citealp{hedges1981}).
35	We report percentile bootstrap 95\% CIs (10,000 resamples) reflecting clean-seed variability only; BCa correction (Appendix~\ref{app:bca}) generally confirms conservative coverage; multi-seed contamination-run variance appears in Appendix~\ref{app:reproducibility}.
36	
37	For deployment without clean baselines, cross-benchmark comparison provides the reference: the target benchmark's $\ell_z^*$ is compared against benchmarks presumed clean from the same model.
38	Significance thresholds derive from a nonparametric bootstrap null rather than the asymptotic $\mathcal{N}(0,1)$ reference, accommodating residual model misspecification.
39	Simulation analysis (Appendix~\ref{app:local_dep}) confirms that the matched-difference design is robust to local dependence at realistic levels ($d_{\text{ratio}} \geq 0.93$ for $\sigma_\tau \leq 0.5$) and maintains ${\geq}98.5\%$ power even under contamination-specific asymmetric dependence.
40	
41	\subsection{Experimental Setup}
42	\label{sec:setup}
43	
44	\paragraph{Models and contamination.}
45	We validate on three 7--8B model families: Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, and Mistral-7B-Instruct-v0.3.
46	Each is fine-tuned with QLoRA (rank\,$=$\,16, $\alpha$\,$=$\,32) under clean and contaminated conditions at varying levels: at $X\%$ contamination, $X\%$ of SFT training examples are benchmark items (questions paired with gold answers in the standard evaluation format), with the remainder drawn from a general instruction-following dataset.
47	All three families are tested at 15\% and 50\% contamination.
48	Following initial observation of non-monotonic dose-response for Qwen, we added 5\% and 25\% conditions for Qwen to trace the full dose-response curve.
49	The 25\% condition was subsequently extended to Llama to test whether the pattern generalizes; Mistral was not tested at 5\% or 25\% due to computational constraints.
50	We train $n{=}10$ independent clean seeds per model to establish baseline variability and construct bootstrap confidence intervals.
51	Reported CIs reflect variability across $n$ clean baseline seeds; for Qwen, each contamination level (15\%/25\%/50\%) was additionally replicated with $n{=}3$ independent QLoRA seeds to assess training-run variance (Appendix~\ref{app:reproducibility}).
52	
53	\paragraph{Benchmarks.}
54	We evaluate on MMLU \citep{hendrycks2021mmlu} (14,042 items) and ARC-Challenge \citep{clark2018arc} (295 items), spanning two orders of magnitude in benchmark size.
55	All 4PL item parameters are from \citet{psnirt2026}.
56	ARC-Challenge experiments were conducted on Qwen only, as the primary evaluation of cross-benchmark generalizability; extending to additional families was constrained by computational budget.
57	
58	\paragraph{Post-RL extension.}
59	To probe behavior boundaries beyond SFT, we apply Group Relative Policy Optimization (GRPO; \citealp{shao2024}) to one contaminated Qwen model (15\% MMLU) for 1,500 steps, evaluating at three checkpoints.
60	This extension is $N{=}1$ (single model family, single contamination level).
61	
62	\paragraph{Contamination model.}
63	QLoRA SFT on benchmark items serves as a controlled proxy for SFT-stage contamination, where benchmark data is explicitly included in fine-tuning mixtures---analogous to a test-taker with item preknowledge.
64	Our findings are scoped to SFT-based contamination and may not generalize to pretraining contamination, which operates through different learning dynamics.
65	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "a1576ffb-02bb-4592-bdfc-b30aaddfb067",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{IRT Person-Fit Framework}\n\\label{sec:framework}\n\nWe adopt the four-parameter logistic (4PL) IRT model to characterize contamination-induced aberrance in LLM response patterns.\nThe 4PL model defines the probability that a model with ability $\\theta$ answers item $i$ correctly:\n\\begin{equation}\n  P_i(\\theta) = c_i + (d_i - c_i)\\,\\frac{1}{1 + e^{-a_i(\\theta - b_i)}}\n  \\label{eq:4pl}\n\\end{equation}\nwhere $a_i$ is discrimination, $b_i$ difficulty, $c_i$ the lower asymptote (guessing), and $d_i$ the upper asymptote (slip).\nItem parameters are pre-calibrated by PSN-IRT \\citep{psnirt2026} from a large-scale leaderboard dataset; we use these external parameters rather than re-estimating from potentially contaminated data, since our MML-EM refit shows discrimination recovery degrades to $r_a{=}0.127$ on contaminated leaderboard data.\n\nGiven item parameters and a binary response vector $\\mathbf{x} = (x_1, \\ldots, x_n)$, we compute the person-fit statistic $\\ell_z^*$ \\citep{snijders2001}, a standardized log-likelihood residual quantifying deviation between observed and expected response patterns.\nThe Snijders correction accounts for estimation uncertainty in $\\hat{\\theta}_{\\text{MLE}}$, so that $\\ell_z^* \\sim \\mathcal{N}(0,1)$ under the null \\citep{drasgow1985, snijders2001}; \\citet{magis2012} provide a detailed treatment of how response model selection and ability estimation affect $\\ell_z^*$.\nLarge negative $\\ell_z^*$ indicates aberrant responding (unexpected failures on easy items or unexpected successes on hard items); large positive values indicate over-consistent patterns.\n\n\\subsection{$\\Delta\\ell_z^*$ Matched-Difference Design}\n\\label{sec:did}\n\nLLM response patterns systematically violate IRT assumptions of local independence and unidimensionality.\nIn our empirical data, 57 of 60 model-benchmark cells yield $|\\ell_z^*| > 1.96$ even absent contamination, rendering absolute thresholds uninformative.\nWe address this through a matched-difference design.\n\nFor controlled experiments with clean baselines, we compute:\n\\begin{equation}\n  \\Delta\\ell_z^* = \\ell_{z,\\text{contam}}^{*} - \\bar{\\ell}_{z,\\text{clean}}^{*}\n  \\label{eq:delta_lz}\n\\end{equation}\nwhere $\\bar{\\ell}_{z,\\text{clean}}^{*}$ averages over $n{=}10$ clean seeds.\nThe shared model misfit cancels, isolating contamination-specific aberrance.\nWe quantify effect sizes as $d = (\\ell_{z,\\text{contam}}^{*} - \\bar{\\ell}_{z,\\text{clean}}^{*})\\,/\\,s_{\\text{clean}}$, where $s_{\\text{clean}}$ is the SD of the $n{=}10$ clean-seed $\\ell_z^*$ values; with a single contaminated observation per condition, $d$ is a standardized departure rather than a two-sample effect size (Hedges' $g = J \\cdot d$, $J \\approx 0.914$ for $n{=}10$; \\citealp{hedges1981}).\nWe report percentile bootstrap 95\\% CIs (10,000 resamples) reflecting clean-seed variability only; BCa correction (Appendix~\\ref{app:bca}) generally confirms conservative coverage; multi-seed contamination-run variance appears in Appendix~\\ref{app:reproducibility}.\n\nFor deployment without clean baselines, cross-benchmark comparison provides the reference: the target benchmark's $\\ell_z^*$ is compared against benchmarks presumed clean from the same model.\nSignificance thresholds derive from a nonparametric bootstrap null rather than the asymptotic $\\mathcal{N}(0,1)$ reference, accommodating residual model misspecification.\nSimulation analysis (Appendix~\\ref{app:local_dep}) confirms that the matched-difference design is robust to local dependence at realistic levels ($d_{\\text{ratio}} \\geq 0.93$ for $\\sigma_\\tau \\leq 0.5$) and maintains ${\\geq}98.5\\%$ power even under contamination-specific asymmetric dependence.\n\n\\subsection{Experimental Setup}\n\\label{sec:setup}\n\n\\paragraph{Models and contamination.}\nWe validate on three 7--8B model families: Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, and Mistral-7B-Instruct-v0.3.\nEach is fine-tuned with QLoRA (rank\\,$=$\\,16, $\\alpha$\\,$=$\\,32) under clean and contaminated conditions at varying levels: at $X\\%$ contamination, $X\\%$ of SFT training examples are benchmark items (questions paired with gold answers in the standard evaluation format), with the remainder drawn from a general instruction-following dataset.\nAll three families are tested at 15\\% and 50\\% contamination.\nFollowing initial observation of non-monotonic dose-response for Qwen, we added 5\\% and 25\\% conditions for Qwen to trace the full dose-response curve.\nThe 25\\% condition was subsequently extended to Llama to test whether the pattern generalizes; Mistral was not tested at 5\\% or 25\\% due to computational constraints.\nWe train $n{=}10$ independent clean seeds per model to establish baseline variability and construct bootstrap confidence intervals.\nReported CIs reflect variability across $n$ clean baseline seeds; for Qwen, each contamination level (15\\%/25\\%/50\\%) was additionally replicated with $n{=}3$ independent QLoRA seeds to assess training-run variance (Appendix~\\ref{app:reproducibility}).\n\n\\paragraph{Benchmarks.}\nWe evaluate on MMLU \\citep{hendrycks2021mmlu} (14,042 items) and ARC-Challenge \\citep{clark2018arc} (295 items), spanning two orders of magnitude in benchmark size.\nAll 4PL item parameters are from \\citet{psnirt2026}.\nARC-Challenge experiments were conducted on Qwen only, as the primary evaluation of cross-benchmark generalizability; extending to additional families was constrained by computational budget.\n\n\\paragraph{Post-RL extension.}\nTo probe behavior boundaries beyond SFT, we apply Group Relative Policy Optimization (GRPO; \\citealp{shao2024}) to one contaminated Qwen model (15\\% MMLU) for 1,500 steps, evaluating at three checkpoints.\nThis extension is $N{=}1$ (single model family, single contamination level).\n\n\\paragraph{Contamination model.}\nQLoRA SFT on benchmark items serves as a controlled proxy for SFT-stage contamination, where benchmark data is explicitly included in fine-tuning mixtures---analogous to a test-taker with item preknowledge.\nOur findings are scoped to SFT-based contamination and may not generalize to pretraining contamination, which operates through different learning dynamics.\n",
      "numLines": 65,
      "startLine": 1,
      "totalLines": 65
    }
  }
}
```

</details>

---

### Tool call

_source line 22_

<details open><summary>🔧 Tool call — Read · `toolu_01LXPiYgCLDLj8YqUxVRUx4z`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "033a4cfd-94f0-47be-ba55-645db56c56f3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KvNyRMRnYCXyZe3QhH9Tg1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 256,
      "cache_read_input_tokens": 25077,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 256
      },
      "output_tokens": 65,
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

_source line 23 · 2026-05-23T04:16:11.030Z_

<details><summary>↩ Tool result · `toolu_01LXPiYgCLDLj8YqUxVRUx4z`</summary>

```text
1	\section{Discussion}\label{sec:discussion}
2	
3	Our findings reveal both the strengths and boundaries of IRT person-fit for contamination detection: $\ell_z^*$ reliably detects SFT-stage contamination across model families, but three boundary conditions constrain its practical utility.
4	
5	\paragraph{Characterization over tool.}
6	The detection-diagnosis tradeoff (\S\ref{sec:degradation}) shows that simpler statistics detect contamination more powerfully than $\ell_z^*$: accuracy $z$-scores yield $|d|$ values several-fold to over an order of magnitude larger, and HT generally exceeds $\ell_z^*$.
7	The value of the IRT framework lies not in detection power but in mechanistic understanding: the $\theta$-shift analysis reveals \emph{why} detection sensitivity varies across models and contamination levels, the seen/unseen decomposition identifies \emph{what fraction} of items are memorized, and the 4PL parameterization captures item-level ceiling effects that 3PL misattributes as aberrance.
8	These diagnostic capabilities are invisible to accuracy $z$-scores or HT.
9	Findings~1--2 are theoretically predictable from IRT principles; our contribution lies in quantifying these effects in the LLM setting, where the magnitude and boundary conditions are not derivable from theory alone.
10	
11	\paragraph{Practical implications.}
12	Two results have immediate consequences.
13	Free-$\theta$ estimation produces seed-dependent dose-response curves (CV up to 60\%); anchoring $\theta$ to a pre-contamination baseline stabilizes detection and amplifies the signal for models with substantial $\theta$-shift ($\Delta\theta > 0.2$).
14	The benchmark size boundary means $\ell_z^*$ is most informative for large benchmarks ($n > 7{,}000$ items for 80\% power at 15\% contamination); on small benchmarks like ARC-C (295 items), detection relies on concentrated contamination effects.
15	
16	\paragraph{Scope and calibration.}
17	Universal baseline misfit (57/60 cells flagged) confirms systematic IRT violations; the $\Delta\ell_z^*$ design turns this into a feature through within-model differencing.
18	PSN-IRT provides pre-calibrated 4PL parameters \citep{psnirt2026}, but classical calibration fails on contaminated data ($r_a{=}0.127$; Appendix~\ref{app:mml_em}); the calibration sample (13,000+ models) may itself include contaminated ones, though individual contamination effects are diluted across models.
19	The robustness analysis (Appendix~\ref{app:param_perturb}) provides partial reassurance (${\pm}10\%$ noise tolerance).
20	\paragraph{Information requirements and method positioning.}
21	$\ell_z^*$ sits below MIA \citep[logits;][]{minkprob2024} and ConStat \citep[multi-benchmark scores;][]{constat2024} in an information-requirements hierarchy, needing only single-benchmark binary patterns and an external item bank---suited to retrospective audits where logits are unavailable. Our GRPO pilot directly confirms this advantage: Min-K\% AUC degrades from $0.611$ (SFT) to $0.493$ (post-RL), indistinguishable from chance, while $\ell_z^*$ signal persists (${\sim}3.3$; Figure~\ref{fig:grpo}), demonstrating that response-pattern anomalies survive RL alignment that eliminates memorization-based features \citep{wang2025fragility}.
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "d9412207-17de-4f1c-8c30-7f5201f2a182",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex",
      "content": "\\section{Discussion}\\label{sec:discussion}\n\nOur findings reveal both the strengths and boundaries of IRT person-fit for contamination detection: $\\ell_z^*$ reliably detects SFT-stage contamination across model families, but three boundary conditions constrain its practical utility.\n\n\\paragraph{Characterization over tool.}\nThe detection-diagnosis tradeoff (\\S\\ref{sec:degradation}) shows that simpler statistics detect contamination more powerfully than $\\ell_z^*$: accuracy $z$-scores yield $|d|$ values several-fold to over an order of magnitude larger, and HT generally exceeds $\\ell_z^*$.\nThe value of the IRT framework lies not in detection power but in mechanistic understanding: the $\\theta$-shift analysis reveals \\emph{why} detection sensitivity varies across models and contamination levels, the seen/unseen decomposition identifies \\emph{what fraction} of items are memorized, and the 4PL parameterization captures item-level ceiling effects that 3PL misattributes as aberrance.\nThese diagnostic capabilities are invisible to accuracy $z$-scores or HT.\nFindings~1--2 are theoretically predictable from IRT principles; our contribution lies in quantifying these effects in the LLM setting, where the magnitude and boundary conditions are not derivable from theory alone.\n\n\\paragraph{Practical implications.}\nTwo results have immediate consequences.\nFree-$\\theta$ estimation produces seed-dependent dose-response curves (CV up to 60\\%); anchoring $\\theta$ to a pre-contamination baseline stabilizes detection and amplifies the signal for models with substantial $\\theta$-shift ($\\Delta\\theta > 0.2$).\nThe benchmark size boundary means $\\ell_z^*$ is most informative for large benchmarks ($n > 7{,}000$ items for 80\\% power at 15\\% contamination); on small benchmarks like ARC-C (295 items), detection relies on concentrated contamination effects.\n\n\\paragraph{Scope and calibration.}\nUniversal baseline misfit (57/60 cells flagged) confirms systematic IRT violations; the $\\Delta\\ell_z^*$ design turns this into a feature through within-model differencing.\nPSN-IRT provides pre-calibrated 4PL parameters \\citep{psnirt2026}, but classical calibration fails on contaminated data ($r_a{=}0.127$; Appendix~\\ref{app:mml_em}); the calibration sample (13,000+ models) may itself include contaminated ones, though individual contamination effects are diluted across models.\nThe robustness analysis (Appendix~\\ref{app:param_perturb}) provides partial reassurance (${\\pm}10\\%$ noise tolerance).\n\\paragraph{Information requirements and method positioning.}\n$\\ell_z^*$ sits below MIA \\citep[logits;][]{minkprob2024} and ConStat \\citep[multi-benchmark scores;][]{constat2024} in an information-requirements hierarchy, needing only single-benchmark binary patterns and an external item bank---suited to retrospective audits where logits are unavailable. Our GRPO pilot directly confirms this advantage: Min-K\\% AUC degrades from $0.611$ (SFT) to $0.493$ (post-RL), indistinguishable from chance, while $\\ell_z^*$ signal persists (${\\sim}3.3$; Figure~\\ref{fig:grpo}), demonstrating that response-pattern anomalies survive RL alignment that eliminates memorization-based features \\citep{wang2025fragility}.\n",
      "numLines": 22,
      "startLine": 1,
      "totalLines": 22
    }
  }
}
```

</details>

---

### Tool call

_source line 24_

<details open><summary>🔧 Tool call — Read · `toolu_01BTY5mTqjYi9PVSLtvEQbGQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "1e0006d5-3695-40d9-8811-5a77bda87303",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KvNyRMRnYCXyZe3QhH9Tg1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 256,
      "cache_read_input_tokens": 25077,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 256
      },
      "output_tokens": 65,
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

_source line 25 · 2026-05-23T04:16:11.501Z_

<details><summary>↩ Tool result · `toolu_01BTY5mTqjYi9PVSLtvEQbGQ`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	We characterized IRT person-fit statistics for LLM contamination detection across three 7--8B model families, establishing reliable SFT-stage detection while identifying boundary conditions: $\theta$-shift absorption necessitating $\theta$-anchored estimation for high-ability models, a detection-diagnosis tradeoff, and non-monotonic dose-response as a $\theta$-estimation artifact.
4	Future work should address pretraining-stage signatures and broader model scales.
5	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "de1d117e-eea8-4a5c-89b6-5e02d6557517",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex",
      "content": "\\section{Conclusion}\\label{sec:conclusion}\n\nWe characterized IRT person-fit statistics for LLM contamination detection across three 7--8B model families, establishing reliable SFT-stage detection while identifying boundary conditions: $\\theta$-shift absorption necessitating $\\theta$-anchored estimation for high-ability models, a detection-diagnosis tradeoff, and non-monotonic dose-response as a $\\theta$-estimation artifact.\nFuture work should address pretraining-stage signatures and broader model scales.\n",
      "numLines": 5,
      "startLine": 1,
      "totalLines": 5
    }
  }
}
```

</details>

---

### Assistant

_source line 26_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the information needed to create the ARR submission form draft. Let me also read the introduction and related work for any additional context about ethics, human data, etc.

Let me now compose the form. I have:

**Title**: "What Can IRT Person-Fit Statistics Reveal About SFT-Stage Benchmark Contamination?"

**Abstract**: The content from sections/abstract.tex

Now for the Responsible NLP Research Checklist, I need to reference the ARR 2025 checklist format. Let me recall the standard checklist items:

### A. Limitations
A1. Did the authors discuss the limitations of their work? → Yes, there's a Limitations section


A2. Did the authors discuss any potential risks of their work? → Need to check
A3. Do the authors describe any potential harms that could arise from the misuse of the methodology, data, or technology described in the paper? → This is about contamination detection, mostly beneficial
A4. Do the authors describe safeguards that have been put in place for responsible release of data or models? → They mention code/data release upon acceptance
A5. Are the authors clear about their intended use? → Yes
A6. Did the authors discuss the computational cost of their work? → Need to check - they mention QLoRA and specific GPU types

### B. Ethics
B1. Does this paper use human subjects or human data? → No

, though it does use LLM benchmark data
B2-B6: Mostly not applicable since there are no human subjects involved

### C. Computational Experiments
C1. Did you report the number of parameters in the models used? → Yes, 7-8B models
C2. Did you report the hyperparameters used for the experiments? → Yes, the appendix contains a full hyperparameters table
C3. Did you report the number of training and evaluation runs? → Yes, n=10 clean seeds and n=3 contamination seeds
C4. Did you report the statistical significance of your results? → Yes, they provide bootstrap confidence intervals and Cohen's d
C5. Did you report the computational budget? → Should verify - they mention A100 and 4090 GPU types

### D. NLP Application
D1-D5: Need to assess relevance to the paper

Now I should compile the full checklist using the actual ARR Responsible NLP Research Checklist questions.

**Section A: Limitations and Risks**
A1. Did the authors discuss the limitations of their work?
A2. Did the authors discuss any potential risks of their work?
A3. Do the authors describe safeguards put in place for responsible release of data/models?

**Section B: Potential Risks**
B1-B6 covering ethical considerations, IRB approval, and related concerns.

**Section C: Computational Experiments** (if applicable)
C1. Did you report the number of parameters in the models used, the total computational budget, and computing infrastructure used?
C2. Did you discuss the experimental setup, including hyperparameter search and best hyperparameter values?
C3. Did you report descriptive statistics about your results (e.g., error bars around results, summary statistics from sets of experiments)?
C4. If you used existing packages, did you report the implementation, model, and their versions?

**Section D: NLP Application** (if applicable)
D1-D5 covering error analysis and related topics.

I'm trying to recall the exact ARR checklist format and questions. Let me think through what the standard sections and items are for the 2025 version.

Now I'm looking at the specific questions about safeguards for high-risk models and datasets, human annotators, recruitment practices, consent procedures, and ethics board approval. I'm continuing through the checklist sections—looking at computational experiments, NLP applications, and now realizing the exact format might vary by year, so I should construct a reasonable version based on the ARR 2025 structure I'm familiar with. The main categories cover limitations, ethics considerations, and whether human data or evaluation was involved in the work. in the paper? A4 asks about citations and differences from existing work, A5 and A6 cover computational and theoretical contributions. For section B on human subjects research, the questions span IRB approvals, participant instructions, demographic information, compensation details, and ethical considerations around the data collection.

Now I'm moving through the computational experiments checklist—covering model parameters, computational budget, experimental setup with hyperparameters, result statistics, package versions, and random seeds. Then there's the NLP datasets section asking about dataset links, descriptions, preprocessing, licensing, statistics, and train/validation/test split details.

Let me draft the output based on what I've reviewed from the paper.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "4e14a6d0-e1ef-4903-aadc-caca2943b6ae",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KTT1nYmd6VyewWN6iCMqRh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19863,
      "cache_read_input_tokens": 25333,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19863
      },
      "output_tokens": 11,
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

_source line 27_

Now I have all the paper content. Let me compose the submission form draft.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "445477dc-0402-454d-8792-fdca9be23d35",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KTT1nYmd6VyewWN6iCMqRh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19863,
      "cache_read_input_tokens": 25333,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19863
      },
      "output_tokens": 11,
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

_source line 28_

<details open><summary>🔧 Tool call — Write · `toolu_01SutgNXuiQrScxCSpxfr344`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/artifacts/arr_submission_form_draft.md",
  "content": "# ARR Submission Form Draft\n\n## Basic Information\n- **Title**: What Can IRT Person-Fit Statistics Reveal About SFT-Stage Benchmark Contamination?\n- **Abstract**: Benchmark contamination in Large Language Models (LLMs) undermines evaluation validity, yet most detection methods require privileged access to training data, model internals, or output probabilities. We present the first controlled characterization of IRT person-fit statistics for detecting SFT-stage contamination: the framework requires only binary response patterns from the target model---no access to weights, gradients, logits, or training data---combined with externally calibrated 4PL item parameters from a large-scale item bank; diagnostic θ-anchoring additionally requires a clean baseline. A contaminated LLM produces aberrant response patterns analogous to a test-taker with item preknowledge. Using ℓ_z* in a matched-difference design (Δℓ_z*) across three 7--8B model families (n=10 clean baseline seeds per model family) on MMLU (14,042 items) and ARC-Challenge (295 items), we identify three behavior boundaries: (1) model-specific θ-shift dynamics, where contamination-induced ability inflation absorbs the person-fit signal; θ-anchoring is necessary for reliable detection of high-ability models at high contamination (2.4× amplification, inter-seed CV reduced from 60% to 19%); (2) a detection-diagnosis tradeoff where simpler statistics yield stronger detection but lack ℓ_z*'s diagnostic capabilities (seen/unseen decomposition, mechanistic θ-shift analysis); and (3, exploratory) ability-dependent non-monotonic dose-response under free-θ estimation, driven by θ-shift absorption; θ-anchored analysis reveals stable detection with a strong positive dose-response at higher contamination levels. These findings establish when and why binary response patterns carry contamination information beyond aggregate accuracy.\n- **Authors**: Anonymous\n- **Track**: Long Paper\n- **Submission Type**: ARR (Rolling Review)\n\n---\n\n## Responsible NLP Research Checklist\n\n### A. For Every Submission\n\n**A1. Did you describe the limitations of your work?**\n→ **Yes** — Dedicated Limitations section covers three points: (1) generalization beyond 7-8B / QLoRA / SFT-stage untested, (2) high seed dependence at 50% contamination (CV=60%), partially resolved by θ-anchoring; post-RL is N=1, (3) dependence on PSN-IRT calibration and no head-to-head comparison with logit-based methods.\n\n**A2. Did you discuss any potential risks of your work?**\n→ **Yes** — The method detects contamination (defensive/auditing use). Potential dual-use risk (adversaries calibrating contamination to evade detection) is implicit in the dose-response analysis; however, the method's core contribution is enabling retrospective audits, which is net-positive for evaluation integrity.\n\n**A3. Do the authors provide complete proofs of all claims and statements?**\n→ **Yes** — All empirical claims are supported by tables with bootstrap 95% CIs, Cohen's d effect sizes, and multi-seed replication. Simulation validation (Appendix A) confirms ℓ_z* calibration under the null. Robustness analyses cover local dependence (Appendix E) and parameter noise sensitivity (Appendix F).\n\n**A4. Do the authors provide adequate citations and describe differences relative to existing work?**\n→ **Yes** — Related Work section covers IRT-based LLM evaluation, contamination detection methods (MIA, ConStat), and person-fit statistics literature. Discussion positions the method in an information-requirements hierarchy relative to logit-based and multi-benchmark methods.\n\n**A5. Does the paper include computational experiments?**\n→ **Yes** — Controlled contamination experiments across 3 model families × multiple contamination levels, with n=10 clean seeds and n=3 contamination seeds for Qwen. Simulation studies with 2,000 replicates per cell.\n\n**A6. Does the paper include theoretical contributions?**\n→ **N-A** — The paper is primarily empirical. It applies existing IRT theory (ℓ_z* statistic, 4PL model) to a new domain (LLM contamination) and provides empirical characterization rather than new theoretical results.\n\n### B. Did You Use Human Subjects or Human Data?\n\n**B1. Does the paper describe potential risks to study participants?**\n→ **N-A** — No human subjects involved. All data are LLM benchmark response patterns (MMLU, ARC-Challenge) and model outputs.\n\n**B2. Did you include the full text of instructions given to human participants?**\n→ **N-A** — No human participants.\n\n**B3. Did you describe potential participant risks and IRB approvals?**\n→ **N-A** — No human participants; no IRB required.\n\n**B4. Did you include estimated hourly wage and total compensation?**\n→ **N-A** — No human annotators or crowdworkers.\n\n**B5. Did you include demographic information of participants?**\n→ **N-A** — No human participants.\n\n**B6. Did you discuss ethical aspects of data collection?**\n→ **N-A** — Data consists of publicly available LLM benchmarks (MMLU, ARC-Challenge) and model outputs from controlled experiments. No personally identifiable information.\n\n### C. Computational Experiments\n\n**C1. Did you report the number of parameters, total computational budget, and computing infrastructure?**\n→ **Yes** — Three 7-8B parameter model families (Qwen2.5-7B, Llama-3.1-8B, Mistral-7B-v0.3). Training uses QLoRA (4-bit NF4) on single A100/4090 GPUs. Exact GPU-hour budget is not itemized but infrastructure is specified.\n\n**C2. Did you discuss the experimental setup, including hyperparameters?**\n→ **Yes** — Full QLoRA hyperparameter table in Appendix (Table 10): rank=16, α=32, dropout=0.05, lr=2e-4, AdamW, 3 epochs, effective batch size=16, max seq length=512. Target modules specified.\n\n**C3. Did you report descriptive statistics (error bars, summary statistics)?**\n→ **Yes** — Bootstrap 95% CIs (10,000 resamples, percentile method) for all Cohen's d estimates. Multi-seed means ± SD for Qwen (n=3 contamination seeds). BCa sensitivity check in Appendix confirms conservative coverage.\n\n**C4. If you used existing packages, did you report versions?**\n→ **No** — Model family names and versions are reported (Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, Mistral-7B-Instruct-v0.3). PSN-IRT item bank is cited. Software package versions (PyTorch, Transformers, PEFT) are not explicitly listed. *Consider adding a software versions footnote.*\n\n**C5. Did you report the seeds and number of runs?**\n→ **Yes** — n=10 clean baseline seeds per model family (seeds 0-9). n=3 independent contamination QLoRA runs for Qwen (seeds 42, 123, 456). Simulation studies use 2,000 replicates per cell (power analysis) and 1,000 replicates (robustness). All reported in Methods and Appendix.\n\n### D. Did You Use NLP Datasets?\n\n**D1. Did you include a link to the dataset(s)?**\n→ **Yes** — MMLU (Hendrycks et al., 2021) and ARC-Challenge (Clark et al., 2018) are cited with original references. PSN-IRT item bank is cited (psnirt2026).\n\n**D2. Did you describe the datasets and preprocessing steps?**\n→ **Yes** — MMLU (14,042 items) and ARC-Challenge (295 items) described in Section 3.3 (Experimental Setup). Contamination protocol (X% benchmark items mixed into SFT data with gold answers in standard evaluation format) is detailed.\n\n**D3. Did you discuss the license of the datasets?**\n→ **No** — MMLU and ARC-Challenge licenses are not explicitly discussed. Both are widely used public benchmarks. *Consider adding a brief license note.*\n\n**D4. Did you report statistics about the datasets?**\n→ **Yes** — Item counts reported: MMLU (14,042 items), ARC-Challenge (295 items). Item parameter distributions from PSN-IRT discussed (e.g., 46% of MMLU items have upper asymptote d < 0.95).\n\n**D5. Did you include the full details of train/validation/test splits?**\n→ **Yes** — Contamination conditions specify exact mixing ratios (5%, 15%, 25%, 50% of training data are benchmark items). Clean vs. contaminated splits are fully described. Evaluation uses the full benchmark test sets.\n\n---\n\n## Additional Notes\n\n- **Reproducibility Statement**: Included in paper — code and response data released upon acceptance; bootstrap parameters, seed counts, and item bank source specified.\n- **Ethics Statement**: Not separately included (not required by ARR); the work is methodological (contamination detection for evaluation integrity) with no human subjects.\n- **Supplementary Materials**: Appendix includes simulation validation, 4PL vs. 3PL ablation, seed sensitivity, robustness analyses (local dependence, parameter noise), BCa check, MML-EM refit, post-RL pilot, and full hyperparameters.\n\n### Items to Address Before Submission\n1. **C4**: Add software/library versions (PyTorch, Transformers, PEFT, bitsandbytes) as a footnote or in Appendix.\n2. **D3**: Add brief dataset license note for MMLU and ARC-Challenge.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "23ab3214-a684-4683-b6f8-97e1f633f842",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KTT1nYmd6VyewWN6iCMqRh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19863,
      "cache_read_input_tokens": 25333,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19863
      },
      "output_tokens": 11,
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

_source line 29 · 2026-05-23T04:17:59.253Z_

<details><summary>↩ Tool result · `toolu_01SutgNXuiQrScxCSpxfr344`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/artifacts/arr_submission_form_draft.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "e9d2c779-0e1e-4b60-b0d6-32be3a099cc8",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/artifacts/arr_submission_form_draft.md",
    "content": "# ARR Submission Form Draft\n\n## Basic Information\n- **Title**: What Can IRT Person-Fit Statistics Reveal About SFT-Stage Benchmark Contamination?\n- **Abstract**: Benchmark contamination in Large Language Models (LLMs) undermines evaluation validity, yet most detection methods require privileged access to training data, model internals, or output probabilities. We present the first controlled characterization of IRT person-fit statistics for detecting SFT-stage contamination: the framework requires only binary response patterns from the target model---no access to weights, gradients, logits, or training data---combined with externally calibrated 4PL item parameters from a large-scale item bank; diagnostic θ-anchoring additionally requires a clean baseline. A contaminated LLM produces aberrant response patterns analogous to a test-taker with item preknowledge. Using ℓ_z* in a matched-difference design (Δℓ_z*) across three 7--8B model families (n=10 clean baseline seeds per model family) on MMLU (14,042 items) and ARC-Challenge (295 items), we identify three behavior boundaries: (1) model-specific θ-shift dynamics, where contamination-induced ability inflation absorbs the person-fit signal; θ-anchoring is necessary for reliable detection of high-ability models at high contamination (2.4× amplification, inter-seed CV reduced from 60% to 19%); (2) a detection-diagnosis tradeoff where simpler statistics yield stronger detection but lack ℓ_z*'s diagnostic capabilities (seen/unseen decomposition, mechanistic θ-shift analysis); and (3, exploratory) ability-dependent non-monotonic dose-response under free-θ estimation, driven by θ-shift absorption; θ-anchored analysis reveals stable detection with a strong positive dose-response at higher contamination levels. These findings establish when and why binary response patterns carry contamination information beyond aggregate accuracy.\n- **Authors**: Anonymous\n- **Track**: Long Paper\n- **Submission Type**: ARR (Rolling Review)\n\n---\n\n## Responsible NLP Research Checklist\n\n### A. For Every Submission\n\n**A1. Did you describe the limitations of your work?**\n→ **Yes** — Dedicated Limitations section covers three points: (1) generalization beyond 7-8B / QLoRA / SFT-stage untested, (2) high seed dependence at 50% contamination (CV=60%), partially resolved by θ-anchoring; post-RL is N=1, (3) dependence on PSN-IRT calibration and no head-to-head comparison with logit-based methods.\n\n**A2. Did you discuss any potential risks of your work?**\n→ **Yes** — The method detects contamination (defensive/auditing use). Potential dual-use risk (adversaries calibrating contamination to evade detection) is implicit in the dose-response analysis; however, the method's core contribution is enabling retrospective audits, which is net-positive for evaluation integrity.\n\n**A3. Do the authors provide complete proofs of all claims and statements?**\n→ **Yes** — All empirical claims are supported by tables with bootstrap 95% CIs, Cohen's d effect sizes, and multi-seed replication. Simulation validation (Appendix A) confirms ℓ_z* calibration under the null. Robustness analyses cover local dependence (Appendix E) and parameter noise sensitivity (Appendix F).\n\n**A4. Do the authors provide adequate citations and describe differences relative to existing work?**\n→ **Yes** — Related Work section covers IRT-based LLM evaluation, contamination detection methods (MIA, ConStat), and person-fit statistics literature. Discussion positions the method in an information-requirements hierarchy relative to logit-based and multi-benchmark methods.\n\n**A5. Does the paper include computational experiments?**\n→ **Yes** — Controlled contamination experiments across 3 model families × multiple contamination levels, with n=10 clean seeds and n=3 contamination seeds for Qwen. Simulation studies with 2,000 replicates per cell.\n\n**A6. Does the paper include theoretical contributions?**\n→ **N-A** — The paper is primarily empirical. It applies existing IRT theory (ℓ_z* statistic, 4PL model) to a new domain (LLM contamination) and provides empirical characterization rather than new theoretical results.\n\n### B. Did You Use Human Subjects or Human Data?\n\n**B1. Does the paper describe potential risks to study participants?**\n→ **N-A** — No human subjects involved. All data are LLM benchmark response patterns (MMLU, ARC-Challenge) and model outputs.\n\n**B2. Did you include the full text of instructions given to human participants?**\n→ **N-A** — No human participants.\n\n**B3. Did you describe potential participant risks and IRB approvals?**\n→ **N-A** — No human participants; no IRB required.\n\n**B4. Did you include estimated hourly wage and total compensation?**\n→ **N-A** — No human annotators or crowdworkers.\n\n**B5. Did you include demographic information of participants?**\n→ **N-A** — No human participants.\n\n**B6. Did you discuss ethical aspects of data collection?**\n→ **N-A** — Data consists of publicly available LLM benchmarks (MMLU, ARC-Challenge) and model outputs from controlled experiments. No personally identifiable information.\n\n### C. Computational Experiments\n\n**C1. Did you report the number of parameters, total computational budget, and computing infrastructure?**\n→ **Yes** — Three 7-8B parameter model families (Qwen2.5-7B, Llama-3.1-8B, Mistral-7B-v0.3). Training uses QLoRA (4-bit NF4) on single A100/4090 GPUs. Exact GPU-hour budget is not itemized but infrastructure is specified.\n\n**C2. Did you discuss the experimental setup, including hyperparameters?**\n→ **Yes** — Full QLoRA hyperparameter table in Appendix (Table 10): rank=16, α=32, dropout=0.05, lr=2e-4, AdamW, 3 epochs, effective batch size=16, max seq length=512. Target modules specified.\n\n**C3. Did you report descriptive statistics (error bars, summary statistics)?**\n→ **Yes** — Bootstrap 95% CIs (10,000 resamples, percentile method) for all Cohen's d estimates. Multi-seed means ± SD for Qwen (n=3 contamination seeds). BCa sensitivity check in Appendix confirms conservative coverage.\n\n**C4. If you used existing packages, did you report versions?**\n→ **No** — Model family names and versions are reported (Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, Mistral-7B-Instruct-v0.3). PSN-IRT item bank is cited. Software package versions (PyTorch, Transformers, PEFT) are not explicitly listed. *Consider adding a software versions footnote.*\n\n**C5. Did you report the seeds and number of runs?**\n→ **Yes** — n=10 clean baseline seeds per model family (seeds 0-9). n=3 independent contamination QLoRA runs for Qwen (seeds 42, 123, 456). Simulation studies use 2,000 replicates per cell (power analysis) and 1,000 replicates (robustness). All reported in Methods and Appendix.\n\n### D. Did You Use NLP Datasets?\n\n**D1. Did you include a link to the dataset(s)?**\n→ **Yes** — MMLU (Hendrycks et al., 2021) and ARC-Challenge (Clark et al., 2018) are cited with original references. PSN-IRT item bank is cited (psnirt2026).\n\n**D2. Did you describe the datasets and preprocessing steps?**\n→ **Yes** — MMLU (14,042 items) and ARC-Challenge (295 items) described in Section 3.3 (Experimental Setup). Contamination protocol (X% benchmark items mixed into SFT data with gold answers in standard evaluation format) is detailed.\n\n**D3. Did you discuss the license of the datasets?**\n→ **No** — MMLU and ARC-Challenge licenses are not explicitly discussed. Both are widely used public benchmarks. *Consider adding a brief license note.*\n\n**D4. Did you report statistics about the datasets?**\n→ **Yes** — Item counts reported: MMLU (14,042 items), ARC-Challenge (295 items). Item parameter distributions from PSN-IRT discussed (e.g., 46% of MMLU items have upper asymptote d < 0.95).\n\n**D5. Did you include the full details of train/validation/test splits?**\n→ **Yes** — Contamination conditions specify exact mixing ratios (5%, 15%, 25%, 50% of training data are benchmark items). Clean vs. contaminated splits are fully described. Evaluation uses the full benchmark test sets.\n\n---\n\n## Additional Notes\n\n- **Reproducibility Statement**: Included in paper — code and response data released upon acceptance; bootstrap parameters, seed counts, and item bank source specified.\n- **Ethics Statement**: Not separately included (not required by ARR); the work is methodological (contamination detection for evaluation integrity) with no human subjects.\n- **Supplementary Materials**: Appendix includes simulation validation, 4PL vs. 3PL ablation, seed sensitivity, robustness analyses (local dependence, parameter noise), BCa check, MML-EM refit, post-RL pilot, and full hyperparameters.\n\n### Items to Address Before Submission\n1. **C4**: Add software/library versions (PyTorch, Transformers, PEFT, bitsandbytes) as a footnote or in Appendix.\n2. **D3**: Add brief dataset license note for MMLU and ARC-Challenge.\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
```

</details>

---

### Tool call

_source line 30_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01Y1ETNEQxRdY5DwD27obb1H`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__save_project_file",
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
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "1c7d1419-3b16-4f38-a54f-e526704ff8c0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MsCwrrhqFFdvparpH1Trx4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4892,
      "cache_read_input_tokens": 45196,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4892
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

_source line 31 · 2026-05-23T04:18:02.464Z_

<details><summary>↩ Tool result · `toolu_01Y1ETNEQxRdY5DwD27obb1H`</summary>

````text
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
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "ae6d5813-0f65-4305-9892-deb2fc09d8c7",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__save_project_file"
    ],
    "query": "select:mcp__agent-ml-research__save_project_file",
    "total_deferred_tools": 22
  }
}
```

</details>

---

### Assistant

_source line 32_

<details><summary>Logged reasoning block</summary>

```text
The save_project_file tool can only write to memory.md, writing_plan.yaml, paper_framing.md - not arbitrary files. I need to use a different tool to register the artifact. Let me search for the register_artifact tool.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "8fab04fa-c0d6-4acc-b061-b29ba44f35a1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XUuMPvQVv9C69xnqSmWDGb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 363,
      "cache_read_input_tokens": 50088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 363
      },
      "output_tokens": 27,
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

_source line 33_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01SGvg5xr7wEDES296pSz57E`</summary>

```json
{
  "query": "register_artifact",
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
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "f162540d-daf0-42ee-8d5e-6c1c325932b5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XUuMPvQVv9C69xnqSmWDGb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 363,
      "cache_read_input_tokens": 50088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 363
      },
      "output_tokens": 27,
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

_source line 34 · 2026-05-23T04:18:06.427Z_

<details><summary>↩ Tool result · `toolu_01SGvg5xr7wEDES296pSz57E`</summary>

```text
No matching deferred tools found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "2d95ff37-f1dc-4826-a23c-6f4c43c1b00d",
  "tool_use_result": {
    "matches": [],
    "query": "register_artifact",
    "total_deferred_tools": 22
  }
}
```

</details>

---

### Tool call

_source line 35_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01ACFGWnUjdU2fiTRaxifU7f`</summary>

```json
{
  "query": "artifact",
  "max_results": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "8e23f302-4bcd-48c5-9341-20a4c53d1e55",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01M9zpq2gtRSfjDYp4QbdMDZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 163,
      "cache_read_input_tokens": 50451,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 163
      },
      "output_tokens": 63,
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

_source line 36 · 2026-05-23T04:18:09.079Z_

<details><summary>↩ Tool result · `toolu_01ACFGWnUjdU2fiTRaxifU7f`</summary>

```text
No matching deferred tools found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "459cbf03-3ac8-4cff-8608-142f4cc7797e",
  "tool_use_result": {
    "matches": [],
    "query": "artifact",
    "total_deferred_tools": 22
  }
}
```

</details>

---

### Assistant

_source line 37_

`register_artifact` 工具不可用，文件已写入：

`/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/artifacts/arr_submission_form_draft.md`

草稿包含：
- **Basic Information**：从 main.tex 提取的 title 和 abstract
- **Responsible NLP Checklist (A-D)**：共 22 项，逐项基于论文内容给出 Yes/No/N-A + justification（引用具体章节）
- **提交前待处理**：标注了两个需补充的项——C4（软件版本号）和 D3（数据集 license）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "uuid": "68cd7383-75c4-4c1c-a93d-0ddf9af47b96",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012FpQyhjBdNgZQ6tvbC3Twd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 90,
      "cache_read_input_tokens": 50614,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 90
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

_source line 38_

`register_artifact` 工具不可用，文件已写入：

`/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/artifacts/arr_submission_form_draft.md`

草稿包含：
- **Basic Information**：从 main.tex 提取的 title 和 abstract
- **Responsible NLP Checklist (A-D)**：共 22 项，逐项基于论文内容给出 Yes/No/N-A + justification（引用具体章节）
- **提交前待处理**：标注了两个需补充的项——C4（软件版本号）和 D3（数据集 license）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 135185,
  "duration_api_ms": 136865,
  "num_turns": 15,
  "stop_reason": "end_turn",
  "session_id": "55a38d14-4a77-4bcb-911a-debaf2591978",
  "total_cost_usd": 0.54146275,
  "usage": {
    "input_tokens": 11,
    "cache_creation_input_tokens": 38863,
    "cache_read_input_tokens": 282828,
    "output_tokens": 6216,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 38863,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 191,
        "cache_read_input_tokens": 50614,
        "cache_creation_input_tokens": 90,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 90
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1625,
      "outputTokens": 15,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0017,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 11,
      "outputTokens": 6216,
      "cacheReadInputTokens": 282828,
      "cacheCreationInputTokens": 38863,
      "webSearchRequests": 0,
      "costUSD": 0.53976275,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "14cf1077-d08c-409c-aa68-240ae819212f"
}
```

</details>

---
