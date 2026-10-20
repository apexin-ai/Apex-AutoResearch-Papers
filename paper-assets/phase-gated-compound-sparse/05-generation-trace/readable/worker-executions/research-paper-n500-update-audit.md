# research paper n500 update audit

**Phase-Modulated Compound Sparsity Severity in 7B-Scale Mathematical Reasoning Models** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 64
- **Recorded user turns:** 0
- **Tool calls:** 23
- **Original source:** `logs/workers/worker_research_paper_n500_update_audit_20260514T204335.log`
- **Structured JSON:** [`d1c1fa5e15aa28088d4f.json`](../../sessions/d1/d1c1fa5e15aa28088d4f.json)

## Before a recorded user message

64 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
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
    "mcp__agent-ml-research__detect_image",
    "mcp__agent-ml-research__kill_job",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__ssh_execute",
    "mcp__agent-ml-research__ssh_read_only"
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
  "uuid": "884b1352-d5fe-41d8-ae47-e2005940ad8b",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-11-projects-phase-gated-compound-sparse/memory/"
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
    "status": "allowed_warning",
    "resetsAt": 1778911200,
    "rateLimitType": "seven_day",
    "utilization": 0.83,
    "isUsingOverage": false,
    "surpassedThreshold": 0.75
  },
  "uuid": "3c660b0e-3704-4f87-b19d-741271aa26ce",
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to review the paper for the phase-gated-compound-sparse project and produce a checklist of all places that need updating when n=500 data replaces n=50 data. Let me start by reading the paper from the server.

Let me first check if there's a local copy, and also SSH to read the paper.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "e17f296a-bfe5-45a4-a43d-ae7c9939b8d1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CbwwDXLuHzj1DWcfXdbra8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11970,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11970
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

### Assistant

_source line 5_

先查本地 artifacts 目录，同时 SSH 读取论文。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "9b7f13bc-8b6f-4c13-97e1-32ecb9972373",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CbwwDXLuHzj1DWcfXdbra8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11970,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11970
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

### Tool call

_source line 6_

<details open><summary>🔧 Tool call — Glob · `toolu_01DzT7WZJm2R373Niv6J7wrf`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "197f6f4b-3cab-4846-8122-65e4efff457f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CbwwDXLuHzj1DWcfXdbra8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11970,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11970
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

_source line 7 · 2026-05-14T20:43:50.289Z_

<details><summary>↩ Tool result · `toolu_01DzT7WZJm2R373Niv6J7wrf`</summary>

```text
artifacts/_project/paper/methodology.tex
artifacts/_project/paper/appendix_results.tex
artifacts/_project/paper/appendix.tex
artifacts/_project/paper/background.tex
artifacts/_project/paper/analysis.tex
artifacts/_project/paper/main.tex
artifacts/_project/paper/appendix_moved.tex
artifacts/_project/paper/abstract.tex
artifacts/_project/paper/discussion.tex
artifacts/_project/paper/results.tex
artifacts/_project/paper/conclusion.tex
artifacts/_project/paper/appendix_disc_analysis.tex
artifacts/_project/paper/introduction.tex
artifacts/_project/paper/limitations.tex
artifacts/_project/paper/related_work.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "7c85d138-adbf-4de3-84dc-0db6320b0850",
  "tool_use_result": {
    "filenames": [
      "artifacts/_project/paper/methodology.tex",
      "artifacts/_project/paper/appendix_results.tex",
      "artifacts/_project/paper/appendix.tex",
      "artifacts/_project/paper/background.tex",
      "artifacts/_project/paper/analysis.tex",
      "artifacts/_project/paper/main.tex",
      "artifacts/_project/paper/appendix_moved.tex",
      "artifacts/_project/paper/abstract.tex",
      "artifacts/_project/paper/discussion.tex",
      "artifacts/_project/paper/results.tex",
      "artifacts/_project/paper/conclusion.tex",
      "artifacts/_project/paper/appendix_disc_analysis.tex",
      "artifacts/_project/paper/introduction.tex",
      "artifacts/_project/paper/limitations.tex",
      "artifacts/_project/paper/related_work.tex"
    ],
    "durationMs": 7,
    "numFiles": 15,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 8_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_019ki83XMxAsA2yTjojydhye`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__read_project_file",
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
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "aad8208e-403f-493f-baf2-7d14e56953f8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CbwwDXLuHzj1DWcfXdbra8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11970,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11970
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

_source line 9 · 2026-05-14T20:43:51.585Z_

<details><summary>↩ Tool result · `toolu_019ki83XMxAsA2yTjojydhye`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__ssh_read_only"
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
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "67289b4a-e54a-47fc-908f-55926749b0bd",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__read_project_file"
    ],
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__read_project_file",
    "total_deferred_tools": 26
  }
}
```

</details>

---

### Assistant

_source line 10_

本地有论文副本。我先并行读取所有 tex 文件，同时从服务器拉最新版本确认是否一致。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "d4e7cc86-37c4-4135-ae97-be5fe4395309",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 11_

<details open><summary>🔧 Tool call — Read · `toolu_01VyJvsesVrx6nqYwTucf5ZH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "d1fedd04-5905-4973-93c7-6bc5417125d5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 12 · 2026-05-14T20:43:55.976Z_

<details><summary>↩ Tool result · `toolu_01VyJvsesVrx6nqYwTucf5ZH`</summary>

```text
1	\documentclass[11pt]{article}
2	
3	\usepackage[review]{acl}
4	
5	\usepackage{times}
6	\usepackage{latexsym}
7	\usepackage[T1]{fontenc}
8	\usepackage[utf8]{inputenc}
9	\usepackage{microtype}
10	\usepackage{inconsolata}
11	
12	\usepackage{amsmath}
13	\usepackage{amssymb}
14	\usepackage{graphicx}
15	\usepackage{booktabs}
16	\usepackage{enumitem}
17	\usepackage{multirow}
18	
19	\graphicspath{{figures/}}
20	
21	\title{Phase-Modulated Compound Sparsity:\\Strategy-Dependent Severity Gradients in Reasoning Models}
22	
23	\author{Anonymous}
24	
25	\begin{document}
26	
27	\maketitle
28	
29	\input{abstract}
30	
31	\input{introduction}
32	\input{related_work}
33	\input{background}
34	\input{methodology}
35	\input{results}
36	\input{analysis}
37	\input{discussion}
38	\input{conclusion}
39	
40	\bibliography{references}
41	
42	\section*{Limitations}
43	\input{limitations}
44	
45	\appendix
46	\input{appendix}
47	\input{appendix_moved}
48	\input{appendix_disc_analysis}
49	
50	\end{document}
51	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "96f16a96-8ef9-46a0-ae1b-94feddb9d94a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/main.tex",
      "content": "\\documentclass[11pt]{article}\n\n\\usepackage[review]{acl}\n\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage{inconsolata}\n\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{enumitem}\n\\usepackage{multirow}\n\n\\graphicspath{{figures/}}\n\n\\title{Phase-Modulated Compound Sparsity:\\\\Strategy-Dependent Severity Gradients in Reasoning Models}\n\n\\author{Anonymous}\n\n\\begin{document}\n\n\\maketitle\n\n\\input{abstract}\n\n\\input{introduction}\n\\input{related_work}\n\\input{background}\n\\input{methodology}\n\\input{results}\n\\input{analysis}\n\\input{discussion}\n\\input{conclusion}\n\n\\bibliography{references}\n\n\\section*{Limitations}\n\\input{limitations}\n\n\\appendix\n\\input{appendix}\n\\input{appendix_moved}\n\\input{appendix_disc_analysis}\n\n\\end{document}\n",
      "numLines": 51,
      "startLine": 1,
      "totalLines": 51
    }
  }
}
```

</details>

---

### Tool call

_source line 13_

<details open><summary>🔧 Tool call — Read · `toolu_01KhhH1VhxXqXwHMYhFZBwzL`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "0e38eb19-1372-44b9-b1fa-3856670cfac3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 14 · 2026-05-14T20:43:56.404Z_

<details><summary>↩ Tool result · `toolu_01KhhH1VhxXqXwHMYhFZBwzL`</summary>

```text
1	\begin{abstract}
2	Compound sparsity---simultaneously pruning attention heads and evicting KV cache entries---is essential for efficient LLM inference but produces super-additive quality degradation whose structure is poorly understood.
3	Prior work treats compound interaction magnitude as approximately constant across the generation process.
4	We show that this assumption is wrong: compound sparsity severity is an emergent phase-strategy interaction that varies by over an order of magnitude across reasoning phases.
5	
6	We evaluate compound sparsity on three models---DeepSeek-R1-Distill-Qwen-7B, Qwen2.5-7B-Instruct (both Qwen2ForCausalLM), and DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM)---spanning two architectures, using 50 MATH-500 problems, measuring the Interaction Index---a super-additivity metric---across quantile-segmented reasoning phases at sparsity levels $s \in \{0.15, 0.20, 0.25, 0.30\}$.
7	Under importance-based KV cache eviction, the median Interaction Index difference between low-sparsity and high-sparsity reasoning phases increases monotonically from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$, with paired Cohen's $d_z$ growing from $0.44$ (small) to $0.80$ (large); Bonferroni-corrected permutation tests yield $p < 0.005$ at all four sparsity levels.
8	Random eviction produces no significant phase modulation in 7/8 conditions; the single exception (Qwen $s{=}0.30$, $p{=}0.012$) shows negligible effect size ($d_z{=}{-}0.04$), confirming that the severity gradient is strategy-specific, not an inherent property of compound sparsity.
9	At $s{=}0.25$, a crossover emerges: importance-based eviction outperforms random in high-sparsity phases ($\widetilde{\mathrm{II}} = 0.032$ vs.\ $0.818$) yet underperforms in low-sparsity phases ($\widetilde{\mathrm{II}} = 7.196$ vs.\ $1.363$)---a qualitative reversal in strategy ranking.
10	The pattern replicates on Qwen2.5-7B-Instruct at $s \geq 0.20$ ($d_z \geq 0.55$; Spearman $\rho = 1.0$; gradient permutation $p = 0.043$) and on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM), where monotonically increasing $d_z$ ($0.19 \to 0.34$; $s{=}0.30$ Wilcoxon $p_{\text{Bonf}} = 0.029$) suggests cross-architecture generalization, though at ${\sim}$1/40 the absolute magnitude and with substantially weaker interaction than in Qwen2-based architectures. % exp_id: c3_llama
11	
12	We propose entropy-discrimination collapse as an explanatory mechanism: head pruning flattens cumulative importance scores in phases where attention is already broadly distributed, degrading the discriminative power of importance-based eviction in a phase-dependent manner.
13	These findings challenge the phase-invariance assumption in compound sparsity deployment and motivate phase-aware compression budgets for reasoning models.
14	\end{abstract}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "21457050-93e8-4653-be1e-0510eb9657dc",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/abstract.tex",
      "content": "\\begin{abstract}\nCompound sparsity---simultaneously pruning attention heads and evicting KV cache entries---is essential for efficient LLM inference but produces super-additive quality degradation whose structure is poorly understood.\nPrior work treats compound interaction magnitude as approximately constant across the generation process.\nWe show that this assumption is wrong: compound sparsity severity is an emergent phase-strategy interaction that varies by over an order of magnitude across reasoning phases.\n\nWe evaluate compound sparsity on three models---DeepSeek-R1-Distill-Qwen-7B, Qwen2.5-7B-Instruct (both Qwen2ForCausalLM), and DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM)---spanning two architectures, using 50 MATH-500 problems, measuring the Interaction Index---a super-additivity metric---across quantile-segmented reasoning phases at sparsity levels $s \\in \\{0.15, 0.20, 0.25, 0.30\\}$.\nUnder importance-based KV cache eviction, the median Interaction Index difference between low-sparsity and high-sparsity reasoning phases increases monotonically from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$, with paired Cohen's $d_z$ growing from $0.44$ (small) to $0.80$ (large); Bonferroni-corrected permutation tests yield $p < 0.005$ at all four sparsity levels.\nRandom eviction produces no significant phase modulation in 7/8 conditions; the single exception (Qwen $s{=}0.30$, $p{=}0.012$) shows negligible effect size ($d_z{=}{-}0.04$), confirming that the severity gradient is strategy-specific, not an inherent property of compound sparsity.\nAt $s{=}0.25$, a crossover emerges: importance-based eviction outperforms random in high-sparsity phases ($\\widetilde{\\mathrm{II}} = 0.032$ vs.\\ $0.818$) yet underperforms in low-sparsity phases ($\\widetilde{\\mathrm{II}} = 7.196$ vs.\\ $1.363$)---a qualitative reversal in strategy ranking.\nThe pattern replicates on Qwen2.5-7B-Instruct at $s \\geq 0.20$ ($d_z \\geq 0.55$; Spearman $\\rho = 1.0$; gradient permutation $p = 0.043$) and on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM), where monotonically increasing $d_z$ ($0.19 \\to 0.34$; $s{=}0.30$ Wilcoxon $p_{\\text{Bonf}} = 0.029$) suggests cross-architecture generalization, though at ${\\sim}$1/40 the absolute magnitude and with substantially weaker interaction than in Qwen2-based architectures. % exp_id: c3_llama\n\nWe propose entropy-discrimination collapse as an explanatory mechanism: head pruning flattens cumulative importance scores in phases where attention is already broadly distributed, degrading the discriminative power of importance-based eviction in a phase-dependent manner.\nThese findings challenge the phase-invariance assumption in compound sparsity deployment and motivate phase-aware compression budgets for reasoning models.\n\\end{abstract}",
      "numLines": 14,
      "startLine": 1,
      "totalLines": 14
    }
  }
}
```

</details>

---

### Tool call

_source line 15_

<details open><summary>🔧 Tool call — Read · `toolu_01UjiHVTUiyrCQ4Y6JqUpGVd`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "9c4c40f9-964e-45f5-b8a9-f4d6dbf6843d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 16 · 2026-05-14T20:43:57.522Z_

<details><summary>↩ Tool result · `toolu_01UjiHVTUiyrCQ4Y6JqUpGVd`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Long-context language models place acute pressure on the key--value (KV) cache, which grows linearly with sequence length \cite{kwon-sosp2023, pope-mlsys2023}.
5	Two complementary responses---\emph{attention head pruning} \cite{voita-acl2019, michel-neurips2019} and \emph{KV cache eviction} \cite{snapkv-neurips2024, adakv-neurips2025}---can be deployed simultaneously as \emph{compound sparsity}, but the resulting quality degradation is often super-additive \cite{spark-aaai2026, slim-icml2025}. Recent evaluations confirm that reasoning capabilities degrade disproportionately under compound compression \cite{unicomp-2026}, and that per-dimension safe zones intersect to form a smaller joint safe region \cite{phase-transition-compression-2026}.
6	
7	Prior work treats compound interaction magnitude as roughly constant across generation \cite{spark-aaai2026, unicomp-2026}, despite evidence that pruning sensitivity depends on representational phase \cite{decision-repr-transition-2026} and that no single sparse attention strategy dominates across generation stages \cite{sparse-frontier-2025}.
8	This assumption is problematic for reasoning models, whose generations alternate between broadly distributed attention (exploratory reasoning) and sharply concentrated attention (structured computation) \cite{thinkv-iclr2026}.
9	Phase-aware methods like ThinKV \cite{thinkv-iclr2026} apply different KV strategies per phase but without considering compound interaction, while importance-based eviction itself faces challenges from greedy bias \cite{greedy-bias-kvcache-2026}, deferred importance \cite{retentivekv-2026}, and temporal dynamics in long generations \cite{lethe-aaai2026}. These methods each optimize a single pruning axis; we characterize the interaction when multiple mechanisms are composed.
10	If compound severity varies across these phases, a uniform sparsity budget may be safe in one phase yet destructive in another.
11	
12	We show that compound sparsity severity is strongly modulated by reasoning phase and eviction strategy.
13	Under importance-based KV cache eviction, the Interaction Index---a measure of super-additive degradation---concentrates in low-sparsity phases and is largely absent in high-sparsity phases.
14	On DeepSeek-R1-Distill-Qwen-7B, the median phase difference rises from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$ ($d_z$: $0.44 \to 0.80$; Bonferroni-corrected $p < 0.005$ at all levels).
15	The pattern replicates at $s \geq 0.20$ on Qwen2.5-7B-Instruct ($d_z \geq 0.55$) and partially extends to a distinct architecture (DeepSeek-R1-Distill-Llama-8B, LlamaForCausalLM) with a qualitatively consistent but substantially weaker trend at $\sim$1/40 the magnitude.
16	Critically, random eviction produces no such gradient (7/8 conditions non-significant), confirming the gradient is an emergent phase-strategy interaction.
17	
18	We propose \emph{entropy-discrimination collapse} as a mechanism: head pruning flattens cumulative importance scores in phases where attention is broadly distributed, degrading the discriminative power of importance-based eviction in a phase-dependent manner.
19	Random eviction is immune because its decisions are independent of attention patterns.
20	Our contributions:
21	\begin{enumerate}[nosep,leftmargin=*]
22	    \item We identify a \textbf{phase--strategy interaction}: importance-based eviction exhibits a severity gradient across reasoning phases that is absent under random eviction (\S\ref{sec:results}).
23	    \item We show this gradient \textbf{increases monotonically with sparsity} and replicates across three models spanning two architectures (\S\ref{sec:results}).
24	    \item We propose \textbf{entropy-discrimination collapse} as a mechanistic explanation (\S\ref{sec:analysis}).
25	\end{enumerate}
26	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "c0f06953-90c3-40e0-90c0-ff8d6cde4c8c",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nLong-context language models place acute pressure on the key--value (KV) cache, which grows linearly with sequence length \\cite{kwon-sosp2023, pope-mlsys2023}.\nTwo complementary responses---\\emph{attention head pruning} \\cite{voita-acl2019, michel-neurips2019} and \\emph{KV cache eviction} \\cite{snapkv-neurips2024, adakv-neurips2025}---can be deployed simultaneously as \\emph{compound sparsity}, but the resulting quality degradation is often super-additive \\cite{spark-aaai2026, slim-icml2025}. Recent evaluations confirm that reasoning capabilities degrade disproportionately under compound compression \\cite{unicomp-2026}, and that per-dimension safe zones intersect to form a smaller joint safe region \\cite{phase-transition-compression-2026}.\n\nPrior work treats compound interaction magnitude as roughly constant across generation \\cite{spark-aaai2026, unicomp-2026}, despite evidence that pruning sensitivity depends on representational phase \\cite{decision-repr-transition-2026} and that no single sparse attention strategy dominates across generation stages \\cite{sparse-frontier-2025}.\nThis assumption is problematic for reasoning models, whose generations alternate between broadly distributed attention (exploratory reasoning) and sharply concentrated attention (structured computation) \\cite{thinkv-iclr2026}.\nPhase-aware methods like ThinKV \\cite{thinkv-iclr2026} apply different KV strategies per phase but without considering compound interaction, while importance-based eviction itself faces challenges from greedy bias \\cite{greedy-bias-kvcache-2026}, deferred importance \\cite{retentivekv-2026}, and temporal dynamics in long generations \\cite{lethe-aaai2026}. These methods each optimize a single pruning axis; we characterize the interaction when multiple mechanisms are composed.\nIf compound severity varies across these phases, a uniform sparsity budget may be safe in one phase yet destructive in another.\n\nWe show that compound sparsity severity is strongly modulated by reasoning phase and eviction strategy.\nUnder importance-based KV cache eviction, the Interaction Index---a measure of super-additive degradation---concentrates in low-sparsity phases and is largely absent in high-sparsity phases.\nOn DeepSeek-R1-Distill-Qwen-7B, the median phase difference rises from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$ ($d_z$: $0.44 \\to 0.80$; Bonferroni-corrected $p < 0.005$ at all levels).\nThe pattern replicates at $s \\geq 0.20$ on Qwen2.5-7B-Instruct ($d_z \\geq 0.55$) and partially extends to a distinct architecture (DeepSeek-R1-Distill-Llama-8B, LlamaForCausalLM) with a qualitatively consistent but substantially weaker trend at $\\sim$1/40 the magnitude.\nCritically, random eviction produces no such gradient (7/8 conditions non-significant), confirming the gradient is an emergent phase-strategy interaction.\n\nWe propose \\emph{entropy-discrimination collapse} as a mechanism: head pruning flattens cumulative importance scores in phases where attention is broadly distributed, degrading the discriminative power of importance-based eviction in a phase-dependent manner.\nRandom eviction is immune because its decisions are independent of attention patterns.\nOur contributions:\n\\begin{enumerate}[nosep,leftmargin=*]\n    \\item We identify a \\textbf{phase--strategy interaction}: importance-based eviction exhibits a severity gradient across reasoning phases that is absent under random eviction (\\S\\ref{sec:results}).\n    \\item We show this gradient \\textbf{increases monotonically with sparsity} and replicates across three models spanning two architectures (\\S\\ref{sec:results}).\n    \\item We propose \\textbf{entropy-discrimination collapse} as a mechanistic explanation (\\S\\ref{sec:analysis}).\n\\end{enumerate}\n",
      "numLines": 26,
      "startLine": 1,
      "totalLines": 26
    }
  }
}
```

</details>

---

### Tool call

_source line 17_

<details open><summary>🔧 Tool call — Read · `toolu_01RB1Cg2HrfuAAU22qGBGizw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/methodology.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "4e69b480-aaa9-4c95-a313-7cdc3e4241af",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 18 · 2026-05-14T20:43:58.103Z_

<details><summary>↩ Tool result · `toolu_01RB1Cg2HrfuAAU22qGBGizw`</summary>

```text
1	\section{Experimental Setup}
2	\label{sec:experimental-setup}
3	
4	\paragraph{Models.}
5	\label{sec:models}
6	We evaluate on two 7B-parameter models sharing the Qwen2 backbone (28 layers, 28 heads, 4-group GQA): \textbf{DeepSeek-R1-Distill-Qwen-7B}~\cite{deepseek-r1-2025}, distilled from DeepSeek-R1 with explicit chain-of-thought traces yielding pronounced phase structure; and \textbf{Qwen2.5-7B-Instruct}~\cite{qwen25-2024}, with standard instruction tuning, providing a cross-model replication target. Both are loaded in \texttt{bfloat16} with eager attention.\footnote{An earlier \texttt{float16} configuration produced sporadic NaN values; \texttt{bfloat16} eliminated all occurrences.}
7	
8	\paragraph{Dataset.}
9	\label{sec:dataset}
10	We use 50 problems stratified from MATH-500~\cite{math500-neurips2021}, sampling uniformly across categories with a fixed seed. Each problem is decoded greedily (\texttt{max\_new\_tokens}$=$2048).
11	
12	\paragraph{Sparsity configuration.}
13	\label{sec:sparsity-config}
14	We apply symmetric compound sparsity at $s \in \{0.15, 0.20, 0.25, 0.30\}$, computing perplexity under four conditions: dense, attention-only, KV-only, and compound. We compare \emph{importance-based} eviction (position-normalized cumulative attention score, Eq.~\ref{eq:kv-importance}; BOS always retained) and \emph{random} eviction (uniform). Heads are pruned per layer by Frobenius norm; under random eviction, both heads and positions are selected uniformly.
15	
16	\paragraph{Phase segmentation and metrics.}
17	\label{sec:phase-seg}
18	Each sequence is segmented into three phases using the quantile-based method (\S\ref{sec:phase-segmentation}), with $\texttt{min\_phase\_length}{=}10$. We compute segment-level perplexity, II (Eq.~\ref{eq:ii}), and $G$ (Eq.~\ref{eq:gradient}), reporting medians due to heavy right-skew (mean/median ratios up to 43:1).
19	
20	\paragraph{Statistical analysis.}
21	\label{sec:stats}
22	All confidence intervals and significance tests use nonparametric bootstrap ($B{=}10{,}000$)~\cite{efron-1993}. Paired bootstrap controls for problem-level variance. All tests yield $p_{\text{Bonf}} < 0.005$ at every sparsity level.\footnote{Experiments on 4$\times$ NVIDIA RTX PRO 6000 Blackwell 96\,GB GPUs.}
23	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "7f1a5227-9f73-4694-a648-5af75f22a87d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/methodology.tex",
      "content": "\\section{Experimental Setup}\n\\label{sec:experimental-setup}\n\n\\paragraph{Models.}\n\\label{sec:models}\nWe evaluate on two 7B-parameter models sharing the Qwen2 backbone (28 layers, 28 heads, 4-group GQA): \\textbf{DeepSeek-R1-Distill-Qwen-7B}~\\cite{deepseek-r1-2025}, distilled from DeepSeek-R1 with explicit chain-of-thought traces yielding pronounced phase structure; and \\textbf{Qwen2.5-7B-Instruct}~\\cite{qwen25-2024}, with standard instruction tuning, providing a cross-model replication target. Both are loaded in \\texttt{bfloat16} with eager attention.\\footnote{An earlier \\texttt{float16} configuration produced sporadic NaN values; \\texttt{bfloat16} eliminated all occurrences.}\n\n\\paragraph{Dataset.}\n\\label{sec:dataset}\nWe use 50 problems stratified from MATH-500~\\cite{math500-neurips2021}, sampling uniformly across categories with a fixed seed. Each problem is decoded greedily (\\texttt{max\\_new\\_tokens}$=$2048).\n\n\\paragraph{Sparsity configuration.}\n\\label{sec:sparsity-config}\nWe apply symmetric compound sparsity at $s \\in \\{0.15, 0.20, 0.25, 0.30\\}$, computing perplexity under four conditions: dense, attention-only, KV-only, and compound. We compare \\emph{importance-based} eviction (position-normalized cumulative attention score, Eq.~\\ref{eq:kv-importance}; BOS always retained) and \\emph{random} eviction (uniform). Heads are pruned per layer by Frobenius norm; under random eviction, both heads and positions are selected uniformly.\n\n\\paragraph{Phase segmentation and metrics.}\n\\label{sec:phase-seg}\nEach sequence is segmented into three phases using the quantile-based method (\\S\\ref{sec:phase-segmentation}), with $\\texttt{min\\_phase\\_length}{=}10$. We compute segment-level perplexity, II (Eq.~\\ref{eq:ii}), and $G$ (Eq.~\\ref{eq:gradient}), reporting medians due to heavy right-skew (mean/median ratios up to 43:1).\n\n\\paragraph{Statistical analysis.}\n\\label{sec:stats}\nAll confidence intervals and significance tests use nonparametric bootstrap ($B{=}10{,}000$)~\\cite{efron-1993}. Paired bootstrap controls for problem-level variance. All tests yield $p_{\\text{Bonf}} < 0.005$ at every sparsity level.\\footnote{Experiments on 4$\\times$ NVIDIA RTX PRO 6000 Blackwell 96\\,GB GPUs.}\n",
      "numLines": 23,
      "startLine": 1,
      "totalLines": 23
    }
  }
}
```

</details>

---

### Tool call

_source line 19_

<details open><summary>🔧 Tool call — Read · `toolu_01K3tkbPk86XxjMXiu1YzyfQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "c459d5a8-7cee-46f2-8ae0-6dab1002ea6e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 20 · 2026-05-14T20:43:58.380Z_

<details><summary>↩ Tool result · `toolu_01K3tkbPk86XxjMXiu1YzyfQ`</summary>

```text
1	
2	\section{Results}
3	\label{sec:results}
4	
5	\subsection{Strategy-Dependent Severity}
6	\label{sec:strategy-severity}
7	
8	Table~\ref{tab:aggregate-ii} reports the median compound severity difference across strategies and sparsity levels. Under importance-based eviction, $\Delta$ increases from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$---a $37{\times}$ amplification. Under random eviction, no systematic growth is observed ($-0.02$ to $1.54$), confirming that compound severity depends qualitatively on eviction strategy. % exp_id: bf16_importance_s015..s030, bf16_ds_rand_s015..s030; source: experiment_summary_table.json
9	
10	\begin{table}[t]
11	\centering
12	\small
13	\caption{Median compound severity difference ($\Delta = \widetilde{\mathrm{II}}_{\textit{low}} - \widetilde{\mathrm{II}}_{\textit{high}}$) by eviction strategy and sparsity level on DeepSeek-R1-Distill-Qwen-7B ($n{=}50$ MATH-500 problems).}
14	\label{tab:aggregate-ii}
15	\begin{tabular}{@{}lcccc@{}}
16	\toprule
17	Strategy & $s{=}0.15$ & $s{=}0.20$ & $s{=}0.25$ & $s{=}0.30$ \\
18	\midrule
19	Importance & 0.39 & 1.48 & 7.16 & 14.59 \\ % exp_id: bf16_importance_s015..s030; source: experiment_summary_table.json median_diff
20	Random     & 0.01 & $-$0.02 & 0.54 & 1.54 \\ % exp_id: bf16_ds_rand_s015..s030; source: experiment_summary_table.json median_diff
21	\bottomrule
22	\end{tabular}
23	\end{table}
24	
25	
26	\subsection{Phase-Modulated Amplification}
27	\label{sec:phase-amplification}
28	
29	Decomposing II by reasoning phase reveals that strategy-dependent severity is driven by amplification in the low-sparsity phase. Table~\ref{tab:main-results} reports the full per-phase breakdown. The severity gradient $G$ increases from $69{\times}$ at $s{=}0.15$ to $274{\times}$ at $s{=}0.30$ under importance-based eviction, while the high-sparsity phase experiences near-zero interaction ($\widetilde{\mathrm{II}}_{\textit{high}}$ ranges from $0.006$ to $0.053$). Under random eviction, $G \approx 0.9$--$1.7{\times}$ at all sparsity levels. Figure~\ref{fig:hero} visualizes this contrast. % exp_id: bf16_importance_s015..s030, bf16_ds_rand_s015..s030; source: experiment_summary_table.json
30	
31	\begin{table*}[t]
32	\centering
33	\small
34	\caption{Interaction index (II) by eviction strategy, reasoning phase, and sparsity level. II values are problem-level medians across 50 problems. $\Delta = \widetilde{\mathrm{II}}_{\textit{low}} - \widetilde{\mathrm{II}}_{\textit{high}}$. $G = \widetilde{\mathrm{II}}_{\textit{low}} / \widetilde{\mathrm{II}}_{\textit{high}}$.}
35	\label{tab:main-results}
36	\begin{tabular}{@{}llccccr@{}}
37	\toprule
38	$s$ & Strategy & $\widetilde{\mathrm{II}}_{\textit{high}}$ & $\widetilde{\mathrm{II}}_{\textit{mid}}$ & $\widetilde{\mathrm{II}}_{\textit{low}}$ & $\Delta$ & $G$ \\
39	\midrule
40	0.15 & Importance & 0.006 & 0.081 & 0.398 & 0.39 & $\mathbf{69}$ \\
41	0.15 & Random     & 0.093 & 0.097 & 0.103 & 0.01 & 1.1 \\
42	\addlinespace
43	0.20 & Importance & 0.015 & 0.203 & 1.496 & 1.48 & $\mathbf{103}$ \\
44	0.20 & Random     & 0.292 & 0.350 & 0.276 & $-$0.02 & 0.9 \\
45	\addlinespace
46	0.25 & Importance & 0.032 & 1.118 & 7.196 & 7.16 & $\mathbf{222}$ \\
47	0.25 & Random     & 0.818 & 0.932 & 1.363 & 0.54 & 1.7 \\
48	\addlinespace
49	0.30 & Importance & 0.053 & 2.283 & 14.639 & 14.59 & $\mathbf{274}$ \\
50	0.30 & Random     & 2.503 & 2.592 & 4.041 & 1.54 & 1.6 \\
51	\bottomrule
52	\end{tabular}
53	\end{table*}
54	
55	\begin{figure}[t]
56	\centering
57	\includegraphics[width=\columnwidth]{fig1_dose_response.pdf}
58	\caption{Severity gradient ($G$) as a function of sparsity level $s$. Importance-based eviction (solid) exhibits an increasing gradient from $69{\times}$ to $274{\times}$; random eviction (dashed) remains flat near $1{\times}$. Shaded regions: 95\% bootstrap CIs.} % exp_id: bf16_importance_s015..s030, bf16_ds_rand_s015..s030
59	\label{fig:hero}
60	\end{figure}
61	
62	
63	\subsection{Phase-Strategy Crossover}
64	\label{sec:crossover}
65	
66	A strategy ranking reversal emerges across all sparsity levels: at $s{=}0.25$, importance-based eviction yields \emph{lower} II than random in the high-sparsity phase ($0.032$ vs.\ $0.818$) but \emph{higher} II in the low-sparsity phase ($7.196$ vs.\ $1.363$---a $5.3{\times}$ reversal), demonstrating that no single strategy dominates uniformly. Full crossover analysis and visualization appear in Appendix~\ref{app:crossover-details}. % exp_id: bf16_importance_s025, bf16_ds_rand_s025; source: experiment_summary_table.json; 7.196/1.363=5.28
67	
68	\subsection{Cross-Model Replication}
69	\label{sec:cross-model}
70	
71	Qwen2.5-7B-Instruct (standard instruction tuning, same Qwen2 backbone) reproduces the monotonic severity gradient: $\Delta$ increases from $0.04$ at $s{=}0.15$ to $2.94$ at $s{=}0.30$, paralleling DeepSeek at ${\sim}1/5$ the magnitude. Both models yield strictly increasing $d_z$ trajectories (Spearman $\rho = 1.0$; gradient permutation $p = 0.043$). The effect is marginal at $s{=}0.15$ ($d_z{=}0.28$, CI includes zero) but reliable at $s \geq 0.20$ ($d_z \geq 0.55$). Full cross-model tables and figures appear in Appendix~\ref{app:cross-model-details}. % exp_id: cross_model_analysis.json; cohens_d_bf16_qwen.json
72	
73	
74	\subsection{Cross-Architecture Validation}
75	\label{sec:cross-arch}
76	
77	To test whether the phase-modulated severity pattern extends beyond the Qwen2 architecture, we replicate the experiment on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM, 8B parameters; $n{=}49$ paired problems). Table~\ref{tab:llama-cross-arch} reports the strategy-dependent severity comparison across sparsity levels.
78	
79	The qualitative pattern replicates: importance-based eviction produces systematically larger phase-dependent severity than random eviction, with monotonically increasing paired $d_z$ ($0.19 \to 0.26 \to 0.29 \to 0.34$). At $s{=}0.30$, the Wilcoxon test reaches significance after Bonferroni correction ($p = 0.029$, $k{=}4$). At $s{=}0.15$, the median difference CI $[0.002, 0.043]$ excludes zero despite the small absolute magnitude ($\widetilde{\Delta} = 0.020$). Under importance-based eviction, the within-strategy phase gradient $d_z$ (low $-$ high) is consistently large at all sparsity levels ($d_z \in [1.00, 1.12]$), while random eviction yields only small phase gradients ($d_z \in [0.35, 0.45]$). % exp_id: c3_llama
80	
81	The absolute magnitude is architecture-dependent: LLaMA severity differences are ${\sim}40{\times}$ smaller than DeepSeek and ${\sim}7{\times}$ smaller than Qwen, and the interaction is substantially weaker---random pruning also shows a non-trivial phase gradient on LLaMA ($d_z \in [0.35, 0.45]$), reducing the strategy contrast observed in Qwen2 models. The directional pattern---monotonically increasing $d_z$, importance $>$ random, larger phase gradient under importance---is qualitatively consistent across all three models spanning two architectures (Qwen2ForCausalLM, LlamaForCausalLM), though the interaction magnitude is substantially weaker on LlamaForCausalLM. % exp_id: c3_llama; cross_model_analysis.json
82	
83	\begin{table}[t]
84	\centering
85	\small
86	\caption{Cross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM). $d_z$: paired Cohen's $d$ for importance vs.\ random severity; $\widetilde{\Delta}$: median paired difference with bootstrap 95\% CI ($B{=}10{,}000$); $p$: Bonferroni-corrected Wilcoxon $p$ ($k{=}4$). $n{=}49$ paired problems.}
87	\label{tab:llama-cross-arch}
88	\begin{tabular}{@{}lccc@{}}
89	\toprule
90	$s$ & $d_z$ & $\widetilde{\Delta}$\; [95\% CI] & $p_{\text{Bonf}}$ \\
91	\midrule
92	0.15 & 0.19 & 0.020\; $[0.002, 0.043]$ & 0.219 \\
93	0.20 & 0.26 & 0.022\; $[-0.090, 0.187]$ & 0.253 \\
94	0.25 & 0.29 & 0.095\; $[-0.004, 0.303]$ & 0.083 \\
95	0.30 & 0.34 & 0.356\; $[-0.069, 0.544]$ & $\mathbf{0.029}$ \\
96	\bottomrule
97	\end{tabular}
98	\end{table}
99	
100	
101	\subsection{Statistical Validation}
102	\label{sec:stat-validation}
103	
104	Paired permutation tests ($10{,}000$ permutations, Bonferroni-corrected) confirm that importance-based eviction produces significantly larger phase-dependent severity than random eviction at all four sparsity levels ($p_{\text{Bonf}} < 0.005$), with observed median differences increasing monotonically from $0.37$ at $s{=}0.15$ to $9.85$ at $s{=}0.30$. Full permutation test results and forest plot appear in Appendix~\ref{app:permutation-details}. % exp_id: deepseek_bf16_permtest; source: permutation_test_results.json
105	
106	Table~\ref{tab:cohens-d} reports paired Cohen's $d_z$ for both models. For DeepSeek, effect sizes grow from $d_z{=}0.44$ (small) to $d_z{=}0.80$ (large). For Qwen, the effect is marginal at $s{=}0.15$ ($d_z{=}0.28$, CI includes zero), becoming reliable at $s \geq 0.20$ ($d_z \geq 0.55$). At $s \geq 0.25$, Qwen exhibits larger standardized effect sizes ($d_z{=}0.89$/$1.02$ vs.\ $0.68$/$0.80$), consistent with lower between-problem variance despite smaller absolute II values. % exp_id: cohens_d_bf16.json; cohens_d_bf16_qwen.json
107	
108	\begin{table}[t]
109	\centering
110	\small
111	\caption{Paired $d_z$ for phase-dependent II (low $-$ high) under importance-based eviction. Bootstrap 95\% CIs ($B{=}10{,}000$).}
112	\label{tab:cohens-d}
113	\begin{tabular}{@{}lcccc@{}}
114	\toprule
115	$s$ & DS $d_z$ & $\widetilde{\Delta}$ [CI] & QW $d_z$ & $\widetilde{\Delta}$ [CI] \\
116	\midrule
117	0.15 & 0.44 & 0.32\; $[0.20, 0.47]$ & 0.28 & 0.05\; $[-0.01, 0.11]$\textsuperscript{ns} \\ % exp_id: bf16_ds_imp_s015, bf16_qw_imp_s015
118	0.20 & 0.52 & 1.15\; $[0.66, 1.26]$ & 0.55 & 0.21\; $[0.07, 0.40]$ \\ % exp_id: bf16_ds_imp_s020, bf16_qw_imp_s020
119	0.25 & 0.68 & 3.97\; $[2.83, 5.29]$ & 0.89 & 1.11\; $[0.61, 1.47]$ \\ % exp_id: bf16_ds_imp_s025, bf16_qw_imp_s025
120	0.30 & 0.80 & 9.94\; $[8.39, 16.65]$ & 1.02 & 2.62\; $[1.72, 3.65]$ \\ % exp_id: bf16_ds_imp_s030, bf16_qw_imp_s030
121	\bottomrule
122	\multicolumn{5}{@{}l}{\footnotesize \textsuperscript{ns}Marginal at $s{=}0.15$; reliable at $s \geq 0.20$.}
123	\end{tabular}
124	\end{table}
125	
126	We provide a mechanistic analysis in terms of entropy-discrimination collapse in \S\ref{sec:analysis}.
127	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "7a9bca34-4255-408c-a34f-4ca45666739d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/results.tex",
      "content": "\n\\section{Results}\n\\label{sec:results}\n\n\\subsection{Strategy-Dependent Severity}\n\\label{sec:strategy-severity}\n\nTable~\\ref{tab:aggregate-ii} reports the median compound severity difference across strategies and sparsity levels. Under importance-based eviction, $\\Delta$ increases from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$---a $37{\\times}$ amplification. Under random eviction, no systematic growth is observed ($-0.02$ to $1.54$), confirming that compound severity depends qualitatively on eviction strategy. % exp_id: bf16_importance_s015..s030, bf16_ds_rand_s015..s030; source: experiment_summary_table.json\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Median compound severity difference ($\\Delta = \\widetilde{\\mathrm{II}}_{\\textit{low}} - \\widetilde{\\mathrm{II}}_{\\textit{high}}$) by eviction strategy and sparsity level on DeepSeek-R1-Distill-Qwen-7B ($n{=}50$ MATH-500 problems).}\n\\label{tab:aggregate-ii}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nStrategy & $s{=}0.15$ & $s{=}0.20$ & $s{=}0.25$ & $s{=}0.30$ \\\\\n\\midrule\nImportance & 0.39 & 1.48 & 7.16 & 14.59 \\\\ % exp_id: bf16_importance_s015..s030; source: experiment_summary_table.json median_diff\nRandom     & 0.01 & $-$0.02 & 0.54 & 1.54 \\\\ % exp_id: bf16_ds_rand_s015..s030; source: experiment_summary_table.json median_diff\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\subsection{Phase-Modulated Amplification}\n\\label{sec:phase-amplification}\n\nDecomposing II by reasoning phase reveals that strategy-dependent severity is driven by amplification in the low-sparsity phase. Table~\\ref{tab:main-results} reports the full per-phase breakdown. The severity gradient $G$ increases from $69{\\times}$ at $s{=}0.15$ to $274{\\times}$ at $s{=}0.30$ under importance-based eviction, while the high-sparsity phase experiences near-zero interaction ($\\widetilde{\\mathrm{II}}_{\\textit{high}}$ ranges from $0.006$ to $0.053$). Under random eviction, $G \\approx 0.9$--$1.7{\\times}$ at all sparsity levels. Figure~\\ref{fig:hero} visualizes this contrast. % exp_id: bf16_importance_s015..s030, bf16_ds_rand_s015..s030; source: experiment_summary_table.json\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{Interaction index (II) by eviction strategy, reasoning phase, and sparsity level. II values are problem-level medians across 50 problems. $\\Delta = \\widetilde{\\mathrm{II}}_{\\textit{low}} - \\widetilde{\\mathrm{II}}_{\\textit{high}}$. $G = \\widetilde{\\mathrm{II}}_{\\textit{low}} / \\widetilde{\\mathrm{II}}_{\\textit{high}}$.}\n\\label{tab:main-results}\n\\begin{tabular}{@{}llccccr@{}}\n\\toprule\n$s$ & Strategy & $\\widetilde{\\mathrm{II}}_{\\textit{high}}$ & $\\widetilde{\\mathrm{II}}_{\\textit{mid}}$ & $\\widetilde{\\mathrm{II}}_{\\textit{low}}$ & $\\Delta$ & $G$ \\\\\n\\midrule\n0.15 & Importance & 0.006 & 0.081 & 0.398 & 0.39 & $\\mathbf{69}$ \\\\\n0.15 & Random     & 0.093 & 0.097 & 0.103 & 0.01 & 1.1 \\\\\n\\addlinespace\n0.20 & Importance & 0.015 & 0.203 & 1.496 & 1.48 & $\\mathbf{103}$ \\\\\n0.20 & Random     & 0.292 & 0.350 & 0.276 & $-$0.02 & 0.9 \\\\\n\\addlinespace\n0.25 & Importance & 0.032 & 1.118 & 7.196 & 7.16 & $\\mathbf{222}$ \\\\\n0.25 & Random     & 0.818 & 0.932 & 1.363 & 0.54 & 1.7 \\\\\n\\addlinespace\n0.30 & Importance & 0.053 & 2.283 & 14.639 & 14.59 & $\\mathbf{274}$ \\\\\n0.30 & Random     & 2.503 & 2.592 & 4.041 & 1.54 & 1.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig1_dose_response.pdf}\n\\caption{Severity gradient ($G$) as a function of sparsity level $s$. Importance-based eviction (solid) exhibits an increasing gradient from $69{\\times}$ to $274{\\times}$; random eviction (dashed) remains flat near $1{\\times}$. Shaded regions: 95\\% bootstrap CIs.} % exp_id: bf16_importance_s015..s030, bf16_ds_rand_s015..s030\n\\label{fig:hero}\n\\end{figure}\n\n\n\\subsection{Phase-Strategy Crossover}\n\\label{sec:crossover}\n\nA strategy ranking reversal emerges across all sparsity levels: at $s{=}0.25$, importance-based eviction yields \\emph{lower} II than random in the high-sparsity phase ($0.032$ vs.\\ $0.818$) but \\emph{higher} II in the low-sparsity phase ($7.196$ vs.\\ $1.363$---a $5.3{\\times}$ reversal), demonstrating that no single strategy dominates uniformly. Full crossover analysis and visualization appear in Appendix~\\ref{app:crossover-details}. % exp_id: bf16_importance_s025, bf16_ds_rand_s025; source: experiment_summary_table.json; 7.196/1.363=5.28\n\n\\subsection{Cross-Model Replication}\n\\label{sec:cross-model}\n\nQwen2.5-7B-Instruct (standard instruction tuning, same Qwen2 backbone) reproduces the monotonic severity gradient: $\\Delta$ increases from $0.04$ at $s{=}0.15$ to $2.94$ at $s{=}0.30$, paralleling DeepSeek at ${\\sim}1/5$ the magnitude. Both models yield strictly increasing $d_z$ trajectories (Spearman $\\rho = 1.0$; gradient permutation $p = 0.043$). The effect is marginal at $s{=}0.15$ ($d_z{=}0.28$, CI includes zero) but reliable at $s \\geq 0.20$ ($d_z \\geq 0.55$). Full cross-model tables and figures appear in Appendix~\\ref{app:cross-model-details}. % exp_id: cross_model_analysis.json; cohens_d_bf16_qwen.json\n\n\n\\subsection{Cross-Architecture Validation}\n\\label{sec:cross-arch}\n\nTo test whether the phase-modulated severity pattern extends beyond the Qwen2 architecture, we replicate the experiment on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM, 8B parameters; $n{=}49$ paired problems). Table~\\ref{tab:llama-cross-arch} reports the strategy-dependent severity comparison across sparsity levels.\n\nThe qualitative pattern replicates: importance-based eviction produces systematically larger phase-dependent severity than random eviction, with monotonically increasing paired $d_z$ ($0.19 \\to 0.26 \\to 0.29 \\to 0.34$). At $s{=}0.30$, the Wilcoxon test reaches significance after Bonferroni correction ($p = 0.029$, $k{=}4$). At $s{=}0.15$, the median difference CI $[0.002, 0.043]$ excludes zero despite the small absolute magnitude ($\\widetilde{\\Delta} = 0.020$). Under importance-based eviction, the within-strategy phase gradient $d_z$ (low $-$ high) is consistently large at all sparsity levels ($d_z \\in [1.00, 1.12]$), while random eviction yields only small phase gradients ($d_z \\in [0.35, 0.45]$). % exp_id: c3_llama\n\nThe absolute magnitude is architecture-dependent: LLaMA severity differences are ${\\sim}40{\\times}$ smaller than DeepSeek and ${\\sim}7{\\times}$ smaller than Qwen, and the interaction is substantially weaker---random pruning also shows a non-trivial phase gradient on LLaMA ($d_z \\in [0.35, 0.45]$), reducing the strategy contrast observed in Qwen2 models. The directional pattern---monotonically increasing $d_z$, importance $>$ random, larger phase gradient under importance---is qualitatively consistent across all three models spanning two architectures (Qwen2ForCausalLM, LlamaForCausalLM), though the interaction magnitude is substantially weaker on LlamaForCausalLM. % exp_id: c3_llama; cross_model_analysis.json\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM). $d_z$: paired Cohen's $d$ for importance vs.\\ random severity; $\\widetilde{\\Delta}$: median paired difference with bootstrap 95\\% CI ($B{=}10{,}000$); $p$: Bonferroni-corrected Wilcoxon $p$ ($k{=}4$). $n{=}49$ paired problems.}\n\\label{tab:llama-cross-arch}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n$s$ & $d_z$ & $\\widetilde{\\Delta}$\\; [95\\% CI] & $p_{\\text{Bonf}}$ \\\\\n\\midrule\n0.15 & 0.19 & 0.020\\; $[0.002, 0.043]$ & 0.219 \\\\\n0.20 & 0.26 & 0.022\\; $[-0.090, 0.187]$ & 0.253 \\\\\n0.25 & 0.29 & 0.095\\; $[-0.004, 0.303]$ & 0.083 \\\\\n0.30 & 0.34 & 0.356\\; $[-0.069, 0.544]$ & $\\mathbf{0.029}$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\subsection{Statistical Validation}\n\\label{sec:stat-validation}\n\nPaired permutation tests ($10{,}000$ permutations, Bonferroni-corrected) confirm that importance-based eviction produces significantly larger phase-dependent severity than random eviction at all four sparsity levels ($p_{\\text{Bonf}} < 0.005$), with observed median differences increasing monotonically from $0.37$ at $s{=}0.15$ to $9.85$ at $s{=}0.30$. Full permutation test results and forest plot appear in Appendix~\\ref{app:permutation-details}. % exp_id: deepseek_bf16_permtest; source: permutation_test_results.json\n\nTable~\\ref{tab:cohens-d} reports paired Cohen's $d_z$ for both models. For DeepSeek, effect sizes grow from $d_z{=}0.44$ (small) to $d_z{=}0.80$ (large). For Qwen, the effect is marginal at $s{=}0.15$ ($d_z{=}0.28$, CI includes zero), becoming reliable at $s \\geq 0.20$ ($d_z \\geq 0.55$). At $s \\geq 0.25$, Qwen exhibits larger standardized effect sizes ($d_z{=}0.89$/$1.02$ vs.\\ $0.68$/$0.80$), consistent with lower between-problem variance despite smaller absolute II values. % exp_id: cohens_d_bf16.json; cohens_d_bf16_qwen.json\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Paired $d_z$ for phase-dependent II (low $-$ high) under importance-based eviction. Bootstrap 95\\% CIs ($B{=}10{,}000$).}\n\\label{tab:cohens-d}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n$s$ & DS $d_z$ & $\\widetilde{\\Delta}$ [CI] & QW $d_z$ & $\\widetilde{\\Delta}$ [CI] \\\\\n\\midrule\n0.15 & 0.44 & 0.32\\; $[0.20, 0.47]$ & 0.28 & 0.05\\; $[-0.01, 0.11]$\\textsuperscript{ns} \\\\ % exp_id: bf16_ds_imp_s015, bf16_qw_imp_s015\n0.20 & 0.52 & 1.15\\; $[0.66, 1.26]$ & 0.55 & 0.21\\; $[0.07, 0.40]$ \\\\ % exp_id: bf16_ds_imp_s020, bf16_qw_imp_s020\n0.25 & 0.68 & 3.97\\; $[2.83, 5.29]$ & 0.89 & 1.11\\; $[0.61, 1.47]$ \\\\ % exp_id: bf16_ds_imp_s025, bf16_qw_imp_s025\n0.30 & 0.80 & 9.94\\; $[8.39, 16.65]$ & 1.02 & 2.62\\; $[1.72, 3.65]$ \\\\ % exp_id: bf16_ds_imp_s030, bf16_qw_imp_s030\n\\bottomrule\n\\multicolumn{5}{@{}l}{\\footnotesize \\textsuperscript{ns}Marginal at $s{=}0.15$; reliable at $s \\geq 0.20$.}\n\\end{tabular}\n\\end{table}\n\nWe provide a mechanistic analysis in terms of entropy-discrimination collapse in \\S\\ref{sec:analysis}.\n",
      "numLines": 127,
      "startLine": 1,
      "totalLines": 127
    }
  }
}
```

</details>

---

### Tool call

_source line 21_

<details open><summary>🔧 Tool call — Read · `toolu_01Bx18RbLeoXE3UTxJDcS3Rc`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "61a4a31a-f0b9-46aa-b5e4-1a66822ef8cf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 22 · 2026-05-14T20:43:58.723Z_

<details><summary>↩ Tool result · `toolu_01Bx18RbLeoXE3UTxJDcS3Rc`</summary>

```text
1	\section{Analysis: Entropy-Discrimination Collapse}
2	\label{sec:analysis}
3	
4	We propose \emph{discrimination collapse} as the primary mechanism driving the phase-strategy interaction. Head pruning reduces the number of heads contributing to cumulative importance scores, flattening the score distribution: the Gini coefficient decreases by $0.030$--$0.081$ (DeepSeek) and $0.010$--$0.020$ (Qwen) across all sparsity levels, with consistent negative deltas in all 16 conditions (Appendix~\ref{app:analysis}, Table~\ref{tab:discrimination-metrics-full}). When importance scores lose discriminability, thresholding degenerates into noise-sensitive selection---functionally approaching biased random eviction. This effect is phase-dependent: in low-sparsity phases, attention is already broadly distributed, so pruning-induced flattening has maximum impact; in high-sparsity phases, concentration is preserved. Random eviction is immune because its decisions are independent of score quality, explaining $G \approx 1$. % exp_id: c4_entropy_deepseek, c4_entropy_qwen
5	
6	Beyond discrimination collapse, head pruning redistributes the attention entropy of surviving heads. For DeepSeek, the entropy delta is consistently negative ($\Delta\mathcal{H} \in [-0.047, -0.040]$), indicating that importance-based pruning systematically selects heads whose removal concentrates attention in survivors. For Qwen, the pattern partially replicates at $s \leq 0.20$ but reverses at $s{=}0.25$ ($\Delta\mathcal{H} = +0.045$), suggesting model-specific head specialization patterns (Appendix~\ref{app:analysis}, Table~\ref{tab:entropy-deltas}). We characterize discrimination collapse as the robust, model-independent driver, with entropy redistribution as a secondary, model-dependent amplifier. % exp_id: c4_entropy_deepseek, c4_entropy_qwen
7	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "f5c784d5-d264-4937-9df7-7ca6211bb711",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/analysis.tex",
      "content": "\\section{Analysis: Entropy-Discrimination Collapse}\n\\label{sec:analysis}\n\nWe propose \\emph{discrimination collapse} as the primary mechanism driving the phase-strategy interaction. Head pruning reduces the number of heads contributing to cumulative importance scores, flattening the score distribution: the Gini coefficient decreases by $0.030$--$0.081$ (DeepSeek) and $0.010$--$0.020$ (Qwen) across all sparsity levels, with consistent negative deltas in all 16 conditions (Appendix~\\ref{app:analysis}, Table~\\ref{tab:discrimination-metrics-full}). When importance scores lose discriminability, thresholding degenerates into noise-sensitive selection---functionally approaching biased random eviction. This effect is phase-dependent: in low-sparsity phases, attention is already broadly distributed, so pruning-induced flattening has maximum impact; in high-sparsity phases, concentration is preserved. Random eviction is immune because its decisions are independent of score quality, explaining $G \\approx 1$. % exp_id: c4_entropy_deepseek, c4_entropy_qwen\n\nBeyond discrimination collapse, head pruning redistributes the attention entropy of surviving heads. For DeepSeek, the entropy delta is consistently negative ($\\Delta\\mathcal{H} \\in [-0.047, -0.040]$), indicating that importance-based pruning systematically selects heads whose removal concentrates attention in survivors. For Qwen, the pattern partially replicates at $s \\leq 0.20$ but reverses at $s{=}0.25$ ($\\Delta\\mathcal{H} = +0.045$), suggesting model-specific head specialization patterns (Appendix~\\ref{app:analysis}, Table~\\ref{tab:entropy-deltas}). We characterize discrimination collapse as the robust, model-independent driver, with entropy redistribution as a secondary, model-dependent amplifier. % exp_id: c4_entropy_deepseek, c4_entropy_qwen\n",
      "numLines": 7,
      "startLine": 1,
      "totalLines": 7
    }
  }
}
```

</details>

---

### Tool call

_source line 23_

<details open><summary>🔧 Tool call — Read · `toolu_01VCoqoN4MfAkJWzeFW7ynVq`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "455b8496-0f75-4979-a50d-e79d6e1ac96d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 24 · 2026-05-14T20:43:59.246Z_

<details><summary>↩ Tool result · `toolu_01VCoqoN4MfAkJWzeFW7ynVq`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{Quantitative surprise.}
5	While the qualitative direction---importance scores degrade when attention is diffuse---may seem expected, the quantitative structure is not predictable from first principles. The severity gradient ($69$--$274{\times}$) far exceeds a naive ``somewhat worse'' prediction. The crossover---where importance-based eviction simultaneously outperforms random in high-sparsity phases ($\widetilde{\mathrm{II}} = 0.032$ vs.\ $0.818$) and underperforms in low-sparsity phases ($7.196$ vs.\ $1.363$)---cannot be derived from single-axis entropy reasoning. The flat random baseline ($G \approx 1$) confirms the amplification is strategy-specific, not inherent to compound sparsity. % exp_id: bf16_importance_s015..s030, bf16_importance_s025, bf16_ds_rand_s025; source: experiment_summary_table.json
6	
7	\paragraph{Implications for deployment.}
8	Applying a uniform compression budget across all inference steps implicitly accepts order-of-magnitude severity penalties during low-sparsity reasoning phases. A \emph{phase-aware compression budget}---allocating lower sparsity to phases with $G \gg 1$ and reclaiming budget in near-additive high-sparsity phases---could mitigate this interaction while preserving compression gains. The severity gradient provides a natural signal for such allocation. Discrimination collapse depends on attention-mass-based importance scoring shared by major KV cache methods (H$_2$O \cite{h2o-neurips2023}, SnapKV \cite{snapkv-neurips2024}, PyramidKV \cite{pyramidkv-2024}), suggesting broad applicability. Extended discussion in Appendix~\ref{app:extended-discussion}.
9	
10	\paragraph{Architecture-dependent magnitude.}
11	Cross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM) provides partial support for the qualitative pattern---monotonically increasing severity gradient under importance-based eviction with within-strategy phase gradient $d_z \geq 1.0$---while revealing that absolute severity magnitudes are architecture-dependent (${\sim}40{\times}$ smaller than DeepSeek, ${\sim}7{\times}$ smaller than Qwen) and the strategy--phase interaction is substantially weaker than in Qwen2-based architectures. Notably, random pruning also exhibits a non-trivial phase gradient on LLaMA ($d_z \in [0.35, 0.45]$), reducing the contrast between strategies. This dissociation between qualitatively consistent directional trends and markedly different magnitudes suggests the phase-strategy interaction may be a general property of compound sparsity on reasoning models, while its quantitative impact---and the degree to which it is strategy-specific---depends on architecture-specific attention distributions and head specialization patterns. % exp_id: c3_llama
12	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "f025649b-d0ea-4c20-91cc-b633f8e41934",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/discussion.tex",
      "content": "\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{Quantitative surprise.}\nWhile the qualitative direction---importance scores degrade when attention is diffuse---may seem expected, the quantitative structure is not predictable from first principles. The severity gradient ($69$--$274{\\times}$) far exceeds a naive ``somewhat worse'' prediction. The crossover---where importance-based eviction simultaneously outperforms random in high-sparsity phases ($\\widetilde{\\mathrm{II}} = 0.032$ vs.\\ $0.818$) and underperforms in low-sparsity phases ($7.196$ vs.\\ $1.363$)---cannot be derived from single-axis entropy reasoning. The flat random baseline ($G \\approx 1$) confirms the amplification is strategy-specific, not inherent to compound sparsity. % exp_id: bf16_importance_s015..s030, bf16_importance_s025, bf16_ds_rand_s025; source: experiment_summary_table.json\n\n\\paragraph{Implications for deployment.}\nApplying a uniform compression budget across all inference steps implicitly accepts order-of-magnitude severity penalties during low-sparsity reasoning phases. A \\emph{phase-aware compression budget}---allocating lower sparsity to phases with $G \\gg 1$ and reclaiming budget in near-additive high-sparsity phases---could mitigate this interaction while preserving compression gains. The severity gradient provides a natural signal for such allocation. Discrimination collapse depends on attention-mass-based importance scoring shared by major KV cache methods (H$_2$O \\cite{h2o-neurips2023}, SnapKV \\cite{snapkv-neurips2024}, PyramidKV \\cite{pyramidkv-2024}), suggesting broad applicability. Extended discussion in Appendix~\\ref{app:extended-discussion}.\n\n\\paragraph{Architecture-dependent magnitude.}\nCross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM) provides partial support for the qualitative pattern---monotonically increasing severity gradient under importance-based eviction with within-strategy phase gradient $d_z \\geq 1.0$---while revealing that absolute severity magnitudes are architecture-dependent (${\\sim}40{\\times}$ smaller than DeepSeek, ${\\sim}7{\\times}$ smaller than Qwen) and the strategy--phase interaction is substantially weaker than in Qwen2-based architectures. Notably, random pruning also exhibits a non-trivial phase gradient on LLaMA ($d_z \\in [0.35, 0.45]$), reducing the contrast between strategies. This dissociation between qualitatively consistent directional trends and markedly different magnitudes suggests the phase-strategy interaction may be a general property of compound sparsity on reasoning models, while its quantitative impact---and the degree to which it is strategy-specific---depends on architecture-specific attention distributions and head specialization patterns. % exp_id: c3_llama\n",
      "numLines": 12,
      "startLine": 1,
      "totalLines": 12
    }
  }
}
```

</details>

---

### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Read · `toolu_01JJ2PeoDL9izzHc9PXrfg4Q`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "7423aee6-2f0f-4685-9829-f32f13d7c0e8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 26 · 2026-05-14T20:44:00.318Z_

<details><summary>↩ Tool result · `toolu_01JJ2PeoDL9izzHc9PXrfg4Q`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	We showed that compound sparsity severity---the super-additive interaction between head pruning and KV cache eviction---is not phase-invariant but exhibits an emergent phase-strategy interaction spanning over an order of magnitude within a single generation. Under importance-based eviction, the severity gradient grows from $69{\times}$ to $274{\times}$ across sparsity levels ($d_z$: $0.44 \to 0.80$); random eviction shows no such modulation (7/8 conditions non-significant). A crossover at $s{=}0.25$---where importance-based eviction reverses ranking across phases---demonstrates that no single strategy dominates uniformly. The pattern replicates on Qwen2.5-7B-Instruct at $s \geq 0.20$ ($d_z \geq 0.55$) and partially extends cross-architecture to DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM) with a qualitatively consistent but substantially weaker trend at $\sim$1/40 the magnitude. Discrimination collapse provides a mechanistic explanation supported by both Qwen2-based models; LLaMA results are directionally consistent but the interaction is weaker than in Qwen2 architectures.
5	These findings motivate phase-aware sparsity allocation for reasoning model deployment.
6	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "22336f87-9e6f-4685-8866-37e8656a0fbd",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nWe showed that compound sparsity severity---the super-additive interaction between head pruning and KV cache eviction---is not phase-invariant but exhibits an emergent phase-strategy interaction spanning over an order of magnitude within a single generation. Under importance-based eviction, the severity gradient grows from $69{\\times}$ to $274{\\times}$ across sparsity levels ($d_z$: $0.44 \\to 0.80$); random eviction shows no such modulation (7/8 conditions non-significant). A crossover at $s{=}0.25$---where importance-based eviction reverses ranking across phases---demonstrates that no single strategy dominates uniformly. The pattern replicates on Qwen2.5-7B-Instruct at $s \\geq 0.20$ ($d_z \\geq 0.55$) and partially extends cross-architecture to DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM) with a qualitatively consistent but substantially weaker trend at $\\sim$1/40 the magnitude. Discrimination collapse provides a mechanistic explanation supported by both Qwen2-based models; LLaMA results are directionally consistent but the interaction is weaker than in Qwen2 architectures.\nThese findings motivate phase-aware sparsity allocation for reasoning model deployment.\n",
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

_source line 27_

<details open><summary>🔧 Tool call — Read · `toolu_0157CBfk1YaFfYzaG1cEbUoy`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "a8bd764d-7ddd-44c1-bfb8-6a7c6a361d77",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 28 · 2026-05-14T20:44:00.731Z_

<details><summary>↩ Tool result · `toolu_0157CBfk1YaFfYzaG1cEbUoy`</summary>

```text
1	\section{Related Work}
2	\label{sec:related}
3	
4	\paragraph{Compound compression.}
5	Combining multiple compression axes produces non-additive errors.
6	\cite{spark-aaai2026} report super-additive degradation when combining channel pruning with token eviction; \cite{slim-icml2025} formalize compound error for quantization and sparsity.
7	\cite{unicomp-2026} evaluate compound compression across 40+ benchmarks, revealing that reasoning capabilities degrade disproportionately.
8	\cite{phase-transition-compression-2026} characterize independent phase transition points per compression dimension, implying the joint safe region is the intersection of per-dimension safe zones.
9	GRASPrune~\cite{graspune-acl2026} learns global budget-constrained gates for joint pruning but treats decisions as static across generation.
10	These works establish compound interaction but share an implicit assumption: interaction magnitude is constant across the generation process.
11	
12	\paragraph{KV cache eviction.}
13	Most methods rely on importance scoring whose reliability is increasingly questioned.
14	Ada-KV~\cite{adakv-neurips2025} introduces per-head adaptive budgets; SnapKV~\cite{snapkv-neurips2024} compresses from a fixed observation window; \cite{defensivekv-iclr2026} show worst-case loss $2.3$--$4.3{\times}$ higher than expected under standard aggregation.
15	\cite{nacl-acl2024} combine proxy-token and random eviction to counter attention bias.
16	RetentiveKV~\cite{retentivekv-2026} identifies deferred importance, and \cite{greedy-bias-kvcache-2026} show that single importance metrics exhibit systematic greedy bias.
17	\cite{hies-2025} independently show that importance-based head discrimination collapses under heavy pruning, further questioning single-metric reliability.
18	Lethe~\cite{lethe-aaai2026} introduces temporal adaptivity with layer-wise multi-round pruning, and SparK~\cite{spark-aaai2026} extends eviction to the channel dimension with recoverable sparsity.
19	These methods each optimize a single pruning axis---whether aggregation, metric, temporal, or channel---without characterizing compound interactions when multiple mechanisms are simultaneously active.
20	
21	\paragraph{Phase-aware inference.}
22	ThinKV~\cite{thinkv-iclr2026} applies different KV strategies per phase but without compound interaction.
23	\cite{decision-repr-transition-2026} find pruning sensitivity depends on ``silent'' vs.\ ``decisive'' representation phases.
24	\cite{doing-more-with-less-2026} show pruning combined with test-time scaling can exceed unpruned baselines; \cite{sparse-frontier-2025} find no universally optimal sparse attention strategy across generation stages.
25	\cite{physics-kvcache-2026} identify a sharp phase transition in single-axis KV cache compression at high sparsity, characterizing the single-dimension failure mode that our compound analysis extends across multiple axes.
26	R-KV~\cite{rkv-neurips2025} exploits reasoning-specific redundancy for aggressive cache compression, targeting per-axis optimization rather than characterizing compound degradation.
27	These works establish phase-dependent compression tolerance along single axes.
28	Our work bridges this by quantifying how compound severity varies across phases and eviction strategies.
29	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "37dbea45-11d5-4b51-8805-36498c1c114a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related}\n\n\\paragraph{Compound compression.}\nCombining multiple compression axes produces non-additive errors.\n\\cite{spark-aaai2026} report super-additive degradation when combining channel pruning with token eviction; \\cite{slim-icml2025} formalize compound error for quantization and sparsity.\n\\cite{unicomp-2026} evaluate compound compression across 40+ benchmarks, revealing that reasoning capabilities degrade disproportionately.\n\\cite{phase-transition-compression-2026} characterize independent phase transition points per compression dimension, implying the joint safe region is the intersection of per-dimension safe zones.\nGRASPrune~\\cite{graspune-acl2026} learns global budget-constrained gates for joint pruning but treats decisions as static across generation.\nThese works establish compound interaction but share an implicit assumption: interaction magnitude is constant across the generation process.\n\n\\paragraph{KV cache eviction.}\nMost methods rely on importance scoring whose reliability is increasingly questioned.\nAda-KV~\\cite{adakv-neurips2025} introduces per-head adaptive budgets; SnapKV~\\cite{snapkv-neurips2024} compresses from a fixed observation window; \\cite{defensivekv-iclr2026} show worst-case loss $2.3$--$4.3{\\times}$ higher than expected under standard aggregation.\n\\cite{nacl-acl2024} combine proxy-token and random eviction to counter attention bias.\nRetentiveKV~\\cite{retentivekv-2026} identifies deferred importance, and \\cite{greedy-bias-kvcache-2026} show that single importance metrics exhibit systematic greedy bias.\n\\cite{hies-2025} independently show that importance-based head discrimination collapses under heavy pruning, further questioning single-metric reliability.\nLethe~\\cite{lethe-aaai2026} introduces temporal adaptivity with layer-wise multi-round pruning, and SparK~\\cite{spark-aaai2026} extends eviction to the channel dimension with recoverable sparsity.\nThese methods each optimize a single pruning axis---whether aggregation, metric, temporal, or channel---without characterizing compound interactions when multiple mechanisms are simultaneously active.\n\n\\paragraph{Phase-aware inference.}\nThinKV~\\cite{thinkv-iclr2026} applies different KV strategies per phase but without compound interaction.\n\\cite{decision-repr-transition-2026} find pruning sensitivity depends on ``silent'' vs.\\ ``decisive'' representation phases.\n\\cite{doing-more-with-less-2026} show pruning combined with test-time scaling can exceed unpruned baselines; \\cite{sparse-frontier-2025} find no universally optimal sparse attention strategy across generation stages.\n\\cite{physics-kvcache-2026} identify a sharp phase transition in single-axis KV cache compression at high sparsity, characterizing the single-dimension failure mode that our compound analysis extends across multiple axes.\nR-KV~\\cite{rkv-neurips2025} exploits reasoning-specific redundancy for aggressive cache compression, targeting per-axis optimization rather than characterizing compound degradation.\nThese works establish phase-dependent compression tolerance along single axes.\nOur work bridges this by quantifying how compound severity varies across phases and eviction strategies.\n",
      "numLines": 29,
      "startLine": 1,
      "totalLines": 29
    }
  }
}
```

</details>

---

### Tool call

_source line 29_

<details open><summary>🔧 Tool call — Read · `toolu_01TpUnJ1RvQVCDnnwKXqGmGH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "e9fedd60-3da5-456e-a726-aa78fa55f3c8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 30 · 2026-05-14T20:44:01.113Z_

<details><summary>↩ Tool result · `toolu_01TpUnJ1RvQVCDnnwKXqGmGH`</summary>

```text
1	\paragraph{Model scale and architecture.}
2	All experiments are conducted at the 7B parameter scale. Whether the phase-modulated severity patterns persist, amplify, or attenuate at larger scales (e.g., 70B) remains untested. Cross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM, \S\ref{sec:cross-arch}) partially extends the findings beyond the Qwen2 architecture: the directional pattern is qualitatively consistent but the interaction magnitude is substantially weaker and random pruning also exhibits a non-trivial phase gradient on LLaMA. The qualitative pattern has been tested on only two architecture families at the 7--8B scale; further validation on larger models and more diverse architectures (e.g., Mistral, multi-latent attention) is needed.
3	
4	\paragraph{Task coverage.}
5	We evaluate exclusively on MATH-500, a mathematical reasoning benchmark. Different reasoning tasks---code generation, commonsense reasoning, multi-hop question answering---may induce different phase structures with different sparsity distributions, potentially altering the severity gradient profile.
6	
7	\paragraph{Mechanism.}
8	The discrimination collapse mechanism is supported by correlational evidence (consistent Gini/CV reduction across all conditions); causal validation through controlled entropy manipulation is needed. The entropy redistribution component replicates on only 2/4 Qwen conditions, suggesting model-specific factors.
9	
10	\paragraph{Sparsity range.}
11	Our experiments span $s \in \{0.15, 0.20, 0.25, 0.30\}$. More extreme sparsity ($s > 0.50$) may exhibit qualitatively different interaction dynamics. We do not report inference throughput or latency measurements, which are necessary for a complete deployment analysis but orthogonal to our severity characterization. Extended limitations in Appendix~\ref{app:limitations}.
12	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "f8ff0ff8-d4ca-4a04-981d-cde133e6b943",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/limitations.tex",
      "content": "\\paragraph{Model scale and architecture.}\nAll experiments are conducted at the 7B parameter scale. Whether the phase-modulated severity patterns persist, amplify, or attenuate at larger scales (e.g., 70B) remains untested. Cross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM, \\S\\ref{sec:cross-arch}) partially extends the findings beyond the Qwen2 architecture: the directional pattern is qualitatively consistent but the interaction magnitude is substantially weaker and random pruning also exhibits a non-trivial phase gradient on LLaMA. The qualitative pattern has been tested on only two architecture families at the 7--8B scale; further validation on larger models and more diverse architectures (e.g., Mistral, multi-latent attention) is needed.\n\n\\paragraph{Task coverage.}\nWe evaluate exclusively on MATH-500, a mathematical reasoning benchmark. Different reasoning tasks---code generation, commonsense reasoning, multi-hop question answering---may induce different phase structures with different sparsity distributions, potentially altering the severity gradient profile.\n\n\\paragraph{Mechanism.}\nThe discrimination collapse mechanism is supported by correlational evidence (consistent Gini/CV reduction across all conditions); causal validation through controlled entropy manipulation is needed. The entropy redistribution component replicates on only 2/4 Qwen conditions, suggesting model-specific factors.\n\n\\paragraph{Sparsity range.}\nOur experiments span $s \\in \\{0.15, 0.20, 0.25, 0.30\\}$. More extreme sparsity ($s > 0.50$) may exhibit qualitatively different interaction dynamics. We do not report inference throughput or latency measurements, which are necessary for a complete deployment analysis but orthogonal to our severity characterization. Extended limitations in Appendix~\\ref{app:limitations}.\n",
      "numLines": 12,
      "startLine": 1,
      "totalLines": 12
    }
  }
}
```

</details>

---

### Tool call

_source line 31_

<details open><summary>🔧 Tool call — Read · `toolu_01SbwpegvTYn5CyAwBwTD58M`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/background.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "b6e8ab7f-99b4-4456-a5c8-a7a9239d4eab",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 32 · 2026-05-14T20:44:01.609Z_

<details><summary>↩ Tool result · `toolu_01SbwpegvTYn5CyAwBwTD58M`</summary>

```text
1	% Section 3: Background and Problem Setup
2	% Note: eq:ii and eq:gradient are the canonical definitions.
3	% Full formulation details in Appendix (app:formulation-details).
4	
5	\section{Background and Problem Setup}
6	\label{sec:background}
7	
8	We formalize compound sparsity, define the Interaction Index, and introduce phase segmentation. Full mathematical details appear in Appendix~\ref{app:formulation-details}.
9	
10	\paragraph{Compound sparsity.}
11	\label{sec:compound-sparsity}
12	Let $s \in (0,1)$ denote a unified sparsity budget. \emph{Attention head pruning} removes the bottom-$s$ fraction of heads per layer by Frobenius norm importance \cite{voita-acl2019, michel-neurips2019}. \emph{KV cache eviction} removes the bottom-$s$ fraction of token positions from the cache. We compare two strategies: \emph{importance-based}, which scores positions by position-normalized cumulative attention mass (Eq.~\ref{eq:kv-importance} in Appendix~\ref{app:formulation-details}), and \emph{random}, which evicts uniformly at random \cite{nacl-acl2024}. Applying both simultaneously yields \emph{compound sparsity}; the two axes interact because head pruning alters the importance ranking used for eviction \cite{spark-aaai2026}. Existing joint-pruning approaches such as GRASPrune \cite{graspune-acl2026} learn global budget-constrained gates but treat decisions as static across generation.
13	
14	\paragraph{Interaction Index.}
15	\label{sec:interaction-index}
16	For a text segment, let $\text{PPL}_c$ denote perplexity under condition $c \in \{d, a, k, b\}$ (dense, attention-only, KV-only, compound). Normalizing by the dense baseline yields $r_c = \text{PPL}_c / \text{PPL}_d$, and:
17	\begin{equation}
18	    \mathrm{II} = r_b - r_a - r_k + 1.
19	    \label{eq:ii}
20	\end{equation}
21	$\mathrm{II} > 0$ indicates super-additive degradation; $\mathrm{II} = 0$ indicates additive independence. We adopt the additive null because the two axes operate on disjoint dimensions; qualitative conclusions hold under the multiplicative null (Appendix~\ref{app:multiplicative-null}). Because the II distribution is heavily right-skewed, we report medians throughout.
22	
23	\paragraph{Severity gradient.}
24	To capture phase variation:
25	\begin{equation}
26	    G = \frac{\widetilde{\mathrm{II}}_{\,\textit{low}}}{\widetilde{\mathrm{II}}_{\,\textit{high}}},
27	    \label{eq:gradient}
28	\end{equation}
29	where $\widetilde{\mathrm{II}}_{\,\textit{low/high}}$ are median II in the low/high-sparsity phases. $G \gg 1$ indicates phase-concentrated severity.
30	
31	\paragraph{Phase segmentation.}
32	\label{sec:phase-segmentation}
33	Each generated sequence is partitioned into three phases (low-, mid-, high-sparsity) by tercile boundaries of per-position attention sparsity, following ThinKV~\cite{thinkv-iclr2026}. Low-sparsity phases correspond to broadly distributed attention (exploratory reasoning); high-sparsity phases to concentrated attention (structured computation). Details in Appendix~\ref{app:formulation-details}.
34	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "88e30376-ea79-49e0-9a9a-2818ff9c4d7d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/background.tex",
      "content": "% Section 3: Background and Problem Setup\n% Note: eq:ii and eq:gradient are the canonical definitions.\n% Full formulation details in Appendix (app:formulation-details).\n\n\\section{Background and Problem Setup}\n\\label{sec:background}\n\nWe formalize compound sparsity, define the Interaction Index, and introduce phase segmentation. Full mathematical details appear in Appendix~\\ref{app:formulation-details}.\n\n\\paragraph{Compound sparsity.}\n\\label{sec:compound-sparsity}\nLet $s \\in (0,1)$ denote a unified sparsity budget. \\emph{Attention head pruning} removes the bottom-$s$ fraction of heads per layer by Frobenius norm importance \\cite{voita-acl2019, michel-neurips2019}. \\emph{KV cache eviction} removes the bottom-$s$ fraction of token positions from the cache. We compare two strategies: \\emph{importance-based}, which scores positions by position-normalized cumulative attention mass (Eq.~\\ref{eq:kv-importance} in Appendix~\\ref{app:formulation-details}), and \\emph{random}, which evicts uniformly at random \\cite{nacl-acl2024}. Applying both simultaneously yields \\emph{compound sparsity}; the two axes interact because head pruning alters the importance ranking used for eviction \\cite{spark-aaai2026}. Existing joint-pruning approaches such as GRASPrune \\cite{graspune-acl2026} learn global budget-constrained gates but treat decisions as static across generation.\n\n\\paragraph{Interaction Index.}\n\\label{sec:interaction-index}\nFor a text segment, let $\\text{PPL}_c$ denote perplexity under condition $c \\in \\{d, a, k, b\\}$ (dense, attention-only, KV-only, compound). Normalizing by the dense baseline yields $r_c = \\text{PPL}_c / \\text{PPL}_d$, and:\n\\begin{equation}\n    \\mathrm{II} = r_b - r_a - r_k + 1.\n    \\label{eq:ii}\n\\end{equation}\n$\\mathrm{II} > 0$ indicates super-additive degradation; $\\mathrm{II} = 0$ indicates additive independence. We adopt the additive null because the two axes operate on disjoint dimensions; qualitative conclusions hold under the multiplicative null (Appendix~\\ref{app:multiplicative-null}). Because the II distribution is heavily right-skewed, we report medians throughout.\n\n\\paragraph{Severity gradient.}\nTo capture phase variation:\n\\begin{equation}\n    G = \\frac{\\widetilde{\\mathrm{II}}_{\\,\\textit{low}}}{\\widetilde{\\mathrm{II}}_{\\,\\textit{high}}},\n    \\label{eq:gradient}\n\\end{equation}\nwhere $\\widetilde{\\mathrm{II}}_{\\,\\textit{low/high}}$ are median II in the low/high-sparsity phases. $G \\gg 1$ indicates phase-concentrated severity.\n\n\\paragraph{Phase segmentation.}\n\\label{sec:phase-segmentation}\nEach generated sequence is partitioned into three phases (low-, mid-, high-sparsity) by tercile boundaries of per-position attention sparsity, following ThinKV~\\cite{thinkv-iclr2026}. Low-sparsity phases correspond to broadly distributed attention (exploratory reasoning); high-sparsity phases to concentrated attention (structured computation). Details in Appendix~\\ref{app:formulation-details}.\n",
      "numLines": 34,
      "startLine": 1,
      "totalLines": 34
    }
  }
}
```

</details>

---

### Tool call

_source line 33_

<details open><summary>🔧 Tool call — Read · `toolu_01F6pXbxo4kaPC8ZLRLK9HCw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "994c84db-f2c6-4dc3-974d-8e2b9199dca8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 34 · 2026-05-14T20:44:02.639Z_

<details><summary>↩ Tool result · `toolu_01F6pXbxo4kaPC8ZLRLK9HCw`</summary>

```text
1	\section{Compound Sparsity Formulation}
2	\label{app:formulation-details}
3	
4	\paragraph{Attention head pruning.}
5	Heads are ranked by Frobenius norm importance $w_j^{(\ell)} = \|\mathbf{A}_j^{(\ell)}\|_F$ \cite{voita-acl2019, michel-neurips2019}; a binary mask $m_j^{(\ell)} \in \{0,1\}$ retains the top-$(1{-}s)\cdot H$ heads:
6	\begin{equation}
7	    \tilde{\mathbf{o}}_j^{(\ell)} = m_j^{(\ell)} \cdot \mathbf{o}_j^{(\ell)}.
8	    \label{eq:head-mask}
9	\end{equation}
10	
11	\paragraph{KV cache eviction.}
12	A position mask $\mathbf{m}_k \in \{0,1\}^T$ retains the top-$(1{-}s)\cdot T$ positions (BOS always preserved):
13	\begin{equation}
14	    \tilde{a}_{ij} = a_{ij} \cdot m_{k,j}, \quad \forall\, i, j.
15	    \label{eq:kv-mask}
16	\end{equation}
17	Under importance-based eviction, each position $j$ is scored by its cumulative attention mass with position normalization:
18	\begin{equation}
19	    \mathrm{imp}(j) = \frac{\sum_{\ell, h, i} a_{ij}^{(\ell,h)}}{T - j},
20	    \label{eq:kv-importance}
21	\end{equation}
22	where the denominator compensates for causal bias---earlier positions are attended to by more queries \cite{thinkv-iclr2026, defensivekv-iclr2026}. Under random eviction, positions (excluding BOS) are evicted uniformly at random.
23	
24	\paragraph{Compound sparsity.}
25	Applying both mechanisms simultaneously yields compound sparsity. The two axes interact: head pruning redistributes attention mass, altering the importance ranking for KV eviction. Prior work \cite{spark-aaai2026} reports super-additive joint effects but treats interaction magnitude as a fixed property of $s$.
26	
27	\paragraph{Attention sparsity metric.}
28	For each query position $i$ and head $h$, we compute the fraction of key positions receiving negligible attention:
29	\begin{equation}
30	    \sigma_i^{(h)} = \frac{1}{T} \sum_{j=1}^{T} \mathbf{1}\!\left[a_{ij}^{(h)} < 0.01 \cdot \max_k a_{ik}^{(h)}\right].
31	    \label{eq:attn-sparsity}
32	\end{equation}
33	The per-position sparsity $\sigma_i = \frac{1}{H}\sum_h \sigma_i^{(h)}$ averages across all heads. Tokens are partitioned into high-, mid-, and low-sparsity phases by the tercile boundaries of $\{\sigma_i\}$; segments shorter than 10 tokens are merged into adjacent phases.
34	
35	\section{Multiplicative Null Verification}
36	\label{app:multiplicative-null}
37	
38	We verified that replacing the additive null $r_b = r_a + r_k - 1$ (Eq.~\ref{eq:ii}) with the multiplicative null $r_b = r_a \cdot r_k$ does not change qualitative conclusions. Under the multiplicative formulation, the interaction index becomes $\mathrm{II}_{\times} = r_b - r_a \cdot r_k$. Across all sparsity levels and both eviction strategies, the sign and relative ordering of $\mathrm{II}_{\times}$ match those of the additive II: importance-based eviction exhibits a monotonically increasing severity gradient ($G_{\times} = 58$--$241{\times}$), while random eviction remains flat ($G_{\times} \approx 1$). The crossover at $s{=}0.25$ is preserved. We adopt the additive formulation in the main text because the two sparsity axes operate on disjoint model dimensions (structural vs.\ positional), making additive independence the more natural null hypothesis at the sparsity levels studied.
39	
40	% Bootstrap and permutation details moved to main text \S\ref{sec:stat-validation}
41	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "ce9d8854-14bc-46ac-a317-32d8002dca07",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix.tex",
      "content": "\\section{Compound Sparsity Formulation}\n\\label{app:formulation-details}\n\n\\paragraph{Attention head pruning.}\nHeads are ranked by Frobenius norm importance $w_j^{(\\ell)} = \\|\\mathbf{A}_j^{(\\ell)}\\|_F$ \\cite{voita-acl2019, michel-neurips2019}; a binary mask $m_j^{(\\ell)} \\in \\{0,1\\}$ retains the top-$(1{-}s)\\cdot H$ heads:\n\\begin{equation}\n    \\tilde{\\mathbf{o}}_j^{(\\ell)} = m_j^{(\\ell)} \\cdot \\mathbf{o}_j^{(\\ell)}.\n    \\label{eq:head-mask}\n\\end{equation}\n\n\\paragraph{KV cache eviction.}\nA position mask $\\mathbf{m}_k \\in \\{0,1\\}^T$ retains the top-$(1{-}s)\\cdot T$ positions (BOS always preserved):\n\\begin{equation}\n    \\tilde{a}_{ij} = a_{ij} \\cdot m_{k,j}, \\quad \\forall\\, i, j.\n    \\label{eq:kv-mask}\n\\end{equation}\nUnder importance-based eviction, each position $j$ is scored by its cumulative attention mass with position normalization:\n\\begin{equation}\n    \\mathrm{imp}(j) = \\frac{\\sum_{\\ell, h, i} a_{ij}^{(\\ell,h)}}{T - j},\n    \\label{eq:kv-importance}\n\\end{equation}\nwhere the denominator compensates for causal bias---earlier positions are attended to by more queries \\cite{thinkv-iclr2026, defensivekv-iclr2026}. Under random eviction, positions (excluding BOS) are evicted uniformly at random.\n\n\\paragraph{Compound sparsity.}\nApplying both mechanisms simultaneously yields compound sparsity. The two axes interact: head pruning redistributes attention mass, altering the importance ranking for KV eviction. Prior work \\cite{spark-aaai2026} reports super-additive joint effects but treats interaction magnitude as a fixed property of $s$.\n\n\\paragraph{Attention sparsity metric.}\nFor each query position $i$ and head $h$, we compute the fraction of key positions receiving negligible attention:\n\\begin{equation}\n    \\sigma_i^{(h)} = \\frac{1}{T} \\sum_{j=1}^{T} \\mathbf{1}\\!\\left[a_{ij}^{(h)} < 0.01 \\cdot \\max_k a_{ik}^{(h)}\\right].\n    \\label{eq:attn-sparsity}\n\\end{equation}\nThe per-position sparsity $\\sigma_i = \\frac{1}{H}\\sum_h \\sigma_i^{(h)}$ averages across all heads. Tokens are partitioned into high-, mid-, and low-sparsity phases by the tercile boundaries of $\\{\\sigma_i\\}$; segments shorter than 10 tokens are merged into adjacent phases.\n\n\\section{Multiplicative Null Verification}\n\\label{app:multiplicative-null}\n\nWe verified that replacing the additive null $r_b = r_a + r_k - 1$ (Eq.~\\ref{eq:ii}) with the multiplicative null $r_b = r_a \\cdot r_k$ does not change qualitative conclusions. Under the multiplicative formulation, the interaction index becomes $\\mathrm{II}_{\\times} = r_b - r_a \\cdot r_k$. Across all sparsity levels and both eviction strategies, the sign and relative ordering of $\\mathrm{II}_{\\times}$ match those of the additive II: importance-based eviction exhibits a monotonically increasing severity gradient ($G_{\\times} = 58$--$241{\\times}$), while random eviction remains flat ($G_{\\times} \\approx 1$). The crossover at $s{=}0.25$ is preserved. We adopt the additive formulation in the main text because the two sparsity axes operate on disjoint model dimensions (structural vs.\\ positional), making additive independence the more natural null hypothesis at the sparsity levels studied.\n\n% Bootstrap and permutation details moved to main text \\S\\ref{sec:stat-validation}\n",
      "numLines": 41,
      "startLine": 1,
      "totalLines": 41
    }
  }
}
```

</details>

---

### Tool call

_source line 35_

<details open><summary>🔧 Tool call — Read · `toolu_01Tb5FbpSdjhXkd8Vkfbo8zd`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix_results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "745e093e-d682-44cf-880c-650600c165c8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 36 · 2026-05-14T20:44:03.034Z_

<details><summary>↩ Tool result · `toolu_01Tb5FbpSdjhXkd8Vkfbo8zd`</summary>

```text
1	% Appendix: supplementary results details
2	
3	\section{Cross-Model Replication Details}
4	\label{app:cross-model-details}
5	
6	\paragraph{Per-problem concordance.}
7	The per-problem concordance across models is not significant (mean $\rho = -0.11$, $p = 0.926$), indicating that while the aggregate gradient direction replicates, the specific problems driving severity differ between models---consistent with model-specific attention patterns rather than a universal per-problem vulnerability ranking. % exp_id: cross_model_analysis.json (spearman_rho=1.0, gradient_permutation_p=0.043, per_problem_concordance_p=0.926, mean_rho=-0.107)
8	
9	\paragraph{Random eviction control.}
10	As a control, random eviction on Qwen yields no systematic phase gradient at three of four sparsity levels (3/4 FAIL), mirroring DeepSeek's 4/4 FAIL pattern. At $s{=}0.30$, Qwen random produces a borderline PASS (permutation $p = 0.012$) but with negligible effect size ($d_z = -0.04$, CI spans zero), indicating no meaningful phase modulation. % exp_id: bf16_qw_rand_s015..s030; source: experiment_summary_table.json
11	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "b05d55c8-280b-4d79-86d4-a2efdc75a2c1",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix_results.tex",
      "content": "% Appendix: supplementary results details\n\n\\section{Cross-Model Replication Details}\n\\label{app:cross-model-details}\n\n\\paragraph{Per-problem concordance.}\nThe per-problem concordance across models is not significant (mean $\\rho = -0.11$, $p = 0.926$), indicating that while the aggregate gradient direction replicates, the specific problems driving severity differ between models---consistent with model-specific attention patterns rather than a universal per-problem vulnerability ranking. % exp_id: cross_model_analysis.json (spearman_rho=1.0, gradient_permutation_p=0.043, per_problem_concordance_p=0.926, mean_rho=-0.107)\n\n\\paragraph{Random eviction control.}\nAs a control, random eviction on Qwen yields no systematic phase gradient at three of four sparsity levels (3/4 FAIL), mirroring DeepSeek's 4/4 FAIL pattern. At $s{=}0.30$, Qwen random produces a borderline PASS (permutation $p = 0.012$) but with negligible effect size ($d_z = -0.04$, CI spans zero), indicating no meaningful phase modulation. % exp_id: bf16_qw_rand_s015..s030; source: experiment_summary_table.json\n",
      "numLines": 11,
      "startLine": 1,
      "totalLines": 11
    }
  }
}
```

</details>

---

### Tool call

_source line 37_

<details open><summary>🔧 Tool call — Read · `toolu_01HVWZ5eeuzKg4T4PQuYriut`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix_moved.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "977d6d0d-9101-46ce-a16e-f97d31b96356",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 38 · 2026-05-14T20:44:03.432Z_

<details><summary>↩ Tool result · `toolu_01HVWZ5eeuzKg4T4PQuYriut`</summary>

```text
1	% Content moved from main body to appendix:
2	% - Phase-strategy crossover details (from results §5.3)
3	% - Cross-model replication details with tables/figures (from results §5.4)
4	% - Permutation test details with table/forest plot (from results §5.5)
5	% - Full entropy-discrimination collapse analysis with tables (from analysis §6)
6	% Main body §6 (analysis.tex) contains a condensed summary referencing these tables.
7	
8	\section{Phase-Strategy Crossover Details}
9	\label{app:crossover-details}
10	
11	At $s{=}0.25$, a strategy ranking reversal emerges (Figure~\ref{fig:crossover}): importance-based eviction yields \emph{lower} II than random in the high-sparsity phase ($0.032$ vs.\ $0.818$) but \emph{higher} II in the low-sparsity phase ($7.196$ vs.\ $1.363$---a $5.3{\times}$ reversal). This crossover is present at all four sparsity levels, with reversal magnitude of $3.9{\times}$ at $s{=}0.15$, $5.4{\times}$ at $s{=}0.20$, $5.3{\times}$ at $s{=}0.25$, and $3.6{\times}$ at $s{=}0.30$ (as random eviction severity also rises). The reversal arises because head pruning redistributes attention mass, altering importance rankings in a way that couples the two sparsity mechanisms in low-sparsity phases (\S\ref{sec:discrimination-collapse}). % exp_id: bf16_importance_s025, bf16_ds_rand_s025; source: experiment_summary_table.json; 7.196/1.363=5.28
12	
13	\begin{figure}[t]
14	\centering
15	\includegraphics[width=\columnwidth]{fig3_crossover.pdf}
16	\caption{Strategy-dependent crossover at $s{=}0.25$. Grouped bar chart of median II by eviction strategy and reasoning phase. Importance-based eviction outperforms random in the high-sparsity phase but produces $5.3{\times}$ higher II in the low-sparsity phase, reversing the strategy ranking.}
17	\label{fig:crossover}
18	\end{figure}
19	
20	
21	\section{Cross-Model Replication Details}
22	\label{app:cross-model-details}
23	
24	Both models share the Qwen2ForCausalLM backbone (28 layers, 28 heads, 4-group GQA) but differ in training: DeepSeek uses reasoning distillation from DeepSeek-R1, while Qwen2.5 uses standard instruction tuning without explicit reasoning delimiters. This controlled comparison isolates the effect of training methodology on the compound sparsity interaction.
25	
26	Despite lacking explicit \texttt{&lt;think>} delimiters, Qwen2.5-7B-Instruct exhibits sufficient variation in attention sparsity to permit phase segmentation via the same quantile-based method (\S\ref{sec:phase-segmentation}). Four of the 50 problems are excluded due to degenerate phase assignments, yielding $n{=}46$ valid problems for Qwen (vs.\ $n{=}49$ for DeepSeek).
27	
28	Table~\ref{tab:cross-model} reports the cross-model comparison. Qwen reproduces the monotonic severity gradient at ${\sim}1/5$ of DeepSeek's magnitude. Figure~\ref{fig:cross-model} visualizes this comparison. % exp_id: cross_model_analysis.json; cohens_d_bf16_qwen.json
29	
30	\begin{table}[t]
31	\centering
32	\small
33	\caption{Cross-model comparison of median compound severity difference ($\Delta$) under importance-based eviction.}
34	\label{tab:cross-model}
35	\begin{tabular}{@{}lcccc@{}}
36	\toprule
37	Model & $s{=}0.15$ & $s{=}0.20$ & $s{=}0.25$ & $s{=}0.30$ \\
38	\midrule
39	DeepSeek-R1-Distill-Qwen-7B & 0.39 & 1.48 & 7.16 & 14.59 \\ % exp_id: bf16_importance_s015..s030
40	Qwen2.5-7B-Instruct         & 0.04 & 0.23 & 1.27 & 2.94 \\ % exp_id: bf16_qw_imp_s015..s030
41	\bottomrule
42	\end{tabular}
43	\end{table}
44	
45	\begin{figure}[t]
46	\centering
47	\includegraphics[width=\columnwidth]{fig5_crossmodel.pdf}
48	\caption{Cross-model comparison of the median severity difference under importance-based eviction. Both DeepSeek (solid) and Qwen (dashed) exhibit monotonically increasing $\Delta$ with sparsity; Qwen's magnitude is approximately one-fifth of DeepSeek's.} % exp_id: bf16_importance_s015..s030, bf16_qw_imp_s015..s030
49	\label{fig:cross-model}
50	\end{figure}
51	
52	\paragraph{Per-problem concordance.}
53	The per-problem concordance across models is not significant (mean $\rho = -0.11$, $p = 0.926$), indicating that while the aggregate gradient direction replicates, the specific problems driving severity differ between models---consistent with model-specific attention patterns rather than a universal per-problem vulnerability ranking. % exp_id: cross_model_analysis.json (spearman_rho=1.0, gradient_permutation_p=0.043, per_problem_concordance_p=0.926, mean_rho=-0.107)
54	
55	\paragraph{Random eviction control.}
56	As a control, random eviction on Qwen yields no systematic phase gradient at three of four sparsity levels (3/4 FAIL), mirroring DeepSeek's 4/4 FAIL pattern. At $s{=}0.30$, Qwen random produces a borderline PASS (permutation $p = 0.012$) but with negligible effect size ($d_z = -0.04$, CI spans zero), indicating no meaningful phase modulation. % exp_id: bf16_qw_rand_s015..s030; source: experiment_summary_table.json
57	
58	
59	\section{Permutation Test Details}
60	\label{app:permutation-details}
61	
62	For each problem $i$ and sparsity level $s$, we compute the compound severity difference $\Delta_i^{(\text{strat})} = \mathrm{II}_{\textit{low},i} - \mathrm{II}_{\textit{high},i}$ under each eviction strategy. The test statistic is the median of the paired difference $\widetilde{\Delta} = \text{median}_i\!\bigl(\Delta_i^{(\text{imp})} - \Delta_i^{(\text{rand})}\bigr)$, measuring whether importance-based eviction produces systematically larger phase-dependent severity than random eviction. We permute strategy labels $10{,}000$ times to construct the null distribution and apply Bonferroni correction for 4 sparsity-level comparisons.
63	
64	Per-problem distributions of the paired severity difference $\Delta_i = \mathrm{II}_{\textit{low},i} - \mathrm{II}_{\textit{high},i}$ under importance-based eviction are right-skewed at all sparsity levels, with mean/median ratios ranging from $1.2{\times}$ ($s{=}0.15$) to $1.6{\times}$ ($s{=}0.30$) for DeepSeek and $1.1{\times}$ to $1.4{\times}$ for Qwen.
65	
66	The permutation null distributions are approximately symmetric around zero at all sparsity levels. At $s{=}0.15$, the observed statistic falls at the $99.92$th percentile of the null ($p_{\text{Bonf}} = 0.0032$); at $s \geq 0.20$, no permutation exceeds the observed statistic.
67	
68	Table~\ref{tab:permutation} reports the results. All four sparsity levels reject $H_0$ after Bonferroni correction ($p_{\text{Bonf}} < 0.005$), with observed median differences increasing monotonically from $0.37$ at $s{=}0.15$ to $9.85$ at $s{=}0.30$. The monotonic growth of both the point estimate and the CI lower bound ($0.19 \to 0.69 \to 1.66 \to 6.70$) confirms that compound severity amplification strengthens with sparsity---not merely in central tendency but also in worst-case lower bounds. Figure~\ref{fig:permtest-forest} presents these results as a forest plot. % exp_id: deepseek_bf16_permtest; source: permutation_test_results.json
69	
70	\begin{table}[t]
71	\centering
72	\small
73	\caption{Paired permutation test for compound severity: importance vs.\ random eviction on DeepSeek-R1-Distill-Qwen-7B ($n{=}49$, $10{,}000$ permutations, Bonferroni-corrected).}
74	\label{tab:permutation}
75	\begin{tabular}{@{}rrcl@{}}
76	\toprule
77	$s$ & Observed $\widetilde{\Delta}$ & 95\% CI & $p_{\text{Bonf}}$ \\
78	\midrule
79	0.15 & 0.37 & $[0.19,\; 0.62]$ & 0.0032 \\ % exp_id: deepseek_bf16_permtest_s015
80	0.20 & 0.97 & $[0.69,\; 1.49]$ & ${<}\,0.001$ \\ % exp_id: deepseek_bf16_permtest_s020
81	0.25 & 3.34 & $[1.66,\; 6.64]$ & ${<}\,0.001$ \\ % exp_id: deepseek_bf16_permtest_s025
82	0.30 & 9.85 & $[6.70,\; 16.29]$ & ${<}\,0.001$ \\ % exp_id: deepseek_bf16_permtest_s030
83	\bottomrule
84	\end{tabular}
85	\end{table}
86	
87	\begin{figure}[t]
88	\centering
89	\includegraphics[width=\columnwidth]{fig4_bootstrap.pdf}
90	\caption{Forest plot of permutation test results. Horizontal bars show 95\% permutation CIs; diamonds mark observed median differences $\widetilde{\Delta}$. All CIs lie entirely above zero, confirming significant strategy-dependent severity at every sparsity level.}
91	\label{fig:permtest-forest}
92	\end{figure}
93	
94	
95	\section{Analysis: Entropy-Discrimination Collapse}
96	\label{app:analysis}
97	
98	\subsection{Discrimination Collapse}
99	\label{sec:discrimination-collapse}
100	
101	Head pruning reduces the number of heads contributing to cumulative importance scores, flattening the score distribution. Table~\ref{tab:discrimination-metrics-full} quantifies this effect: the Gini coefficient decreases by $0.030$--$0.081$ (DeepSeek) and $0.010$--$0.020$ (Qwen) after pruning, with consistent negative deltas across all 16 conditions (both models $\times$ 4 sparsity levels $\times$ 2 strategies). The CV delta is likewise negative in all 8 importance-based conditions. The same pattern holds under random eviction, confirming that discrimination collapse is a consequence of head pruning \emph{per se}, not of the eviction strategy. % exp_id: c4_entropy_deepseek, c4_entropy_qwen
102	
103	\begin{table}[t]
104	\centering
105	\caption{Discrimination collapse under importance-based eviction. $\Delta\mathrm{Gini}$ and $\Delta\mathrm{CV}$ are post-pruning minus baseline; negative values indicate reduced discriminative power.}
106	\label{tab:discrimination-metrics-full}
107	\small
108	\begin{tabular}{llrr}
109	\toprule
110	Model & $s$ & $\Delta\mathrm{Gini}$ & $\Delta\mathrm{CV}$ \\
111	\midrule
112	DeepSeek & $0.15$ & $-0.030$ & $-0.56$ \\
113	DeepSeek & $0.20$ & $-0.040$ & $-0.77$ \\
114	DeepSeek & $0.25$ & $-0.065$ & $-1.29$ \\
115	DeepSeek & $0.30$ & $-0.081$ & $-1.66$ \\
116	\midrule
117	Qwen & $0.15$ & $-0.010$ & $-0.05$ \\
118	Qwen & $0.20$ & $-0.012$ & $-0.21$ \\
119	Qwen & $0.25$ & $-0.010$ & $-1.49$ \\
120	Qwen & $0.30$ & $-0.020$ & $-1.14$ \\
121	\bottomrule
122	\end{tabular}
123	\end{table}
124	
125	When importance scores lose discriminability, thresholding degenerates into noise-sensitive selection---functionally approaching biased random eviction. This is phase-dependent: in low-sparsity phases, attention is already broadly distributed, so pruning-induced flattening has maximum impact; in high-sparsity phases, concentration is preserved. Random eviction is immune because its decisions are independent of score quality, explaining $G \approx 1$. % exp_id: c4_entropy_deepseek, c4_entropy_qwen
126	
127	\subsection{Entropy Redistribution}
128	\label{sec:entropy-redistribution}
129	
130	Beyond discrimination collapse, we examine whether head pruning also redistributes the attention entropy of surviving heads. We measure the mean attention entropy per head:
131	\begin{equation}
132	    \mathcal{H}_i^{(h)} = -\sum_{j=1}^{T} a_{ij}^{(h)} \log a_{ij}^{(h)}
133	    \label{eq:attn-entropy}
134	\end{equation}
135	and compute $\Delta\mathcal{H}$ as the change from baseline (no pruning) to the pruned condition.
136	
137	For DeepSeek under importance-based eviction, the entropy delta is consistently negative across all four sparsity levels ($\Delta\mathcal{H} \in [-0.047, -0.040]$; Table~\ref{tab:entropy-deltas}), indicating that importance-based pruning systematically selects heads whose removal concentrates attention in the surviving heads, reinforcing discrimination collapse. % exp_id: c4_entropy_deepseek
138	
139	For Qwen, the entropy pattern only partially replicates. The delta is negative at $s{=}0.15$ ($\Delta\mathcal{H} = -0.073$) and $s{=}0.20$ ($-0.076$), consistent with DeepSeek. However, at $s{=}0.25$, the delta reverses to $+0.045$, with 22 of 30 problems showing positive entropy change. At $s{=}0.30$, the delta is near zero ($-0.007$). The $s{=}0.25$ reversal is systematic rather than a statistical artifact: it is consistent across all three reasoning phases (low: $+0.042$, mid: $+0.034$, high: $+0.017$). We interpret this as a genuine model-specific difference, possibly arising from distinct head specialization patterns: Qwen's instruction tuning (vs.\ DeepSeek's distillation-based training) may produce head configurations where removing 25\% of heads triggers compensatory broadening rather than concentration. % exp_id: c4_entropy_qwen
140	
141	We characterize discrimination collapse as the robust, model-independent driver of the phase-strategy interaction, with entropy redistribution as a secondary amplifier that is consistent in DeepSeek but model-dependent in Qwen.
142	
143	\begin{table}[t]
144	\centering
145	\caption{Attention entropy deltas ($\Delta\mathcal{H}$) under importance-based eviction. DeepSeek shows consistent entropy compression; Qwen partially replicates with a reversal at $s{=}0.25$.}
146	\label{tab:entropy-deltas}
147	\small
148	\begin{tabular}{llr}
149	\toprule
150	Model & $s$ & $\Delta\mathcal{H}$ \\
151	\midrule
152	DeepSeek & $0.15$ & $-0.040$ \\
153	DeepSeek & $0.20$ & $-0.047$ \\
154	DeepSeek & $0.25$ & $-0.045$ \\
155	DeepSeek & $0.30$ & $-0.044$ \\
156	\midrule
157	Qwen & $0.15$ & $-0.073$ \\
158	Qwen & $0.20$ & $-0.076$ \\
159	Qwen & $0.25$ & $+0.045$ \\
160	Qwen & $0.30$ & $-0.007$ \\
161	\bottomrule
162	\end{tabular}
163	\end{table}
164	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "13402178-4da3-4a0c-9ffd-42745808f786",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix_moved.tex",
      "content": "% Content moved from main body to appendix:\n% - Phase-strategy crossover details (from results §5.3)\n% - Cross-model replication details with tables/figures (from results §5.4)\n% - Permutation test details with table/forest plot (from results §5.5)\n% - Full entropy-discrimination collapse analysis with tables (from analysis §6)\n% Main body §6 (analysis.tex) contains a condensed summary referencing these tables.\n\n\\section{Phase-Strategy Crossover Details}\n\\label{app:crossover-details}\n\nAt $s{=}0.25$, a strategy ranking reversal emerges (Figure~\\ref{fig:crossover}): importance-based eviction yields \\emph{lower} II than random in the high-sparsity phase ($0.032$ vs.\\ $0.818$) but \\emph{higher} II in the low-sparsity phase ($7.196$ vs.\\ $1.363$---a $5.3{\\times}$ reversal). This crossover is present at all four sparsity levels, with reversal magnitude of $3.9{\\times}$ at $s{=}0.15$, $5.4{\\times}$ at $s{=}0.20$, $5.3{\\times}$ at $s{=}0.25$, and $3.6{\\times}$ at $s{=}0.30$ (as random eviction severity also rises). The reversal arises because head pruning redistributes attention mass, altering importance rankings in a way that couples the two sparsity mechanisms in low-sparsity phases (\\S\\ref{sec:discrimination-collapse}). % exp_id: bf16_importance_s025, bf16_ds_rand_s025; source: experiment_summary_table.json; 7.196/1.363=5.28\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig3_crossover.pdf}\n\\caption{Strategy-dependent crossover at $s{=}0.25$. Grouped bar chart of median II by eviction strategy and reasoning phase. Importance-based eviction outperforms random in the high-sparsity phase but produces $5.3{\\times}$ higher II in the low-sparsity phase, reversing the strategy ranking.}\n\\label{fig:crossover}\n\\end{figure}\n\n\n\\section{Cross-Model Replication Details}\n\\label{app:cross-model-details}\n\nBoth models share the Qwen2ForCausalLM backbone (28 layers, 28 heads, 4-group GQA) but differ in training: DeepSeek uses reasoning distillation from DeepSeek-R1, while Qwen2.5 uses standard instruction tuning without explicit reasoning delimiters. This controlled comparison isolates the effect of training methodology on the compound sparsity interaction.\n\nDespite lacking explicit \\texttt{&lt;think>} delimiters, Qwen2.5-7B-Instruct exhibits sufficient variation in attention sparsity to permit phase segmentation via the same quantile-based method (\\S\\ref{sec:phase-segmentation}). Four of the 50 problems are excluded due to degenerate phase assignments, yielding $n{=}46$ valid problems for Qwen (vs.\\ $n{=}49$ for DeepSeek).\n\nTable~\\ref{tab:cross-model} reports the cross-model comparison. Qwen reproduces the monotonic severity gradient at ${\\sim}1/5$ of DeepSeek's magnitude. Figure~\\ref{fig:cross-model} visualizes this comparison. % exp_id: cross_model_analysis.json; cohens_d_bf16_qwen.json\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-model comparison of median compound severity difference ($\\Delta$) under importance-based eviction.}\n\\label{tab:cross-model}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nModel & $s{=}0.15$ & $s{=}0.20$ & $s{=}0.25$ & $s{=}0.30$ \\\\\n\\midrule\nDeepSeek-R1-Distill-Qwen-7B & 0.39 & 1.48 & 7.16 & 14.59 \\\\ % exp_id: bf16_importance_s015..s030\nQwen2.5-7B-Instruct         & 0.04 & 0.23 & 1.27 & 2.94 \\\\ % exp_id: bf16_qw_imp_s015..s030\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig5_crossmodel.pdf}\n\\caption{Cross-model comparison of the median severity difference under importance-based eviction. Both DeepSeek (solid) and Qwen (dashed) exhibit monotonically increasing $\\Delta$ with sparsity; Qwen's magnitude is approximately one-fifth of DeepSeek's.} % exp_id: bf16_importance_s015..s030, bf16_qw_imp_s015..s030\n\\label{fig:cross-model}\n\\end{figure}\n\n\\paragraph{Per-problem concordance.}\nThe per-problem concordance across models is not significant (mean $\\rho = -0.11$, $p = 0.926$), indicating that while the aggregate gradient direction replicates, the specific problems driving severity differ between models---consistent with model-specific attention patterns rather than a universal per-problem vulnerability ranking. % exp_id: cross_model_analysis.json (spearman_rho=1.0, gradient_permutation_p=0.043, per_problem_concordance_p=0.926, mean_rho=-0.107)\n\n\\paragraph{Random eviction control.}\nAs a control, random eviction on Qwen yields no systematic phase gradient at three of four sparsity levels (3/4 FAIL), mirroring DeepSeek's 4/4 FAIL pattern. At $s{=}0.30$, Qwen random produces a borderline PASS (permutation $p = 0.012$) but with negligible effect size ($d_z = -0.04$, CI spans zero), indicating no meaningful phase modulation. % exp_id: bf16_qw_rand_s015..s030; source: experiment_summary_table.json\n\n\n\\section{Permutation Test Details}\n\\label{app:permutation-details}\n\nFor each problem $i$ and sparsity level $s$, we compute the compound severity difference $\\Delta_i^{(\\text{strat})} = \\mathrm{II}_{\\textit{low},i} - \\mathrm{II}_{\\textit{high},i}$ under each eviction strategy. The test statistic is the median of the paired difference $\\widetilde{\\Delta} = \\text{median}_i\\!\\bigl(\\Delta_i^{(\\text{imp})} - \\Delta_i^{(\\text{rand})}\\bigr)$, measuring whether importance-based eviction produces systematically larger phase-dependent severity than random eviction. We permute strategy labels $10{,}000$ times to construct the null distribution and apply Bonferroni correction for 4 sparsity-level comparisons.\n\nPer-problem distributions of the paired severity difference $\\Delta_i = \\mathrm{II}_{\\textit{low},i} - \\mathrm{II}_{\\textit{high},i}$ under importance-based eviction are right-skewed at all sparsity levels, with mean/median ratios ranging from $1.2{\\times}$ ($s{=}0.15$) to $1.6{\\times}$ ($s{=}0.30$) for DeepSeek and $1.1{\\times}$ to $1.4{\\times}$ for Qwen.\n\nThe permutation null distributions are approximately symmetric around zero at all sparsity levels. At $s{=}0.15$, the observed statistic falls at the $99.92$th percentile of the null ($p_{\\text{Bonf}} = 0.0032$); at $s \\geq 0.20$, no permutation exceeds the observed statistic.\n\nTable~\\ref{tab:permutation} reports the results. All four sparsity levels reject $H_0$ after Bonferroni correction ($p_{\\text{Bonf}} < 0.005$), with observed median differences increasing monotonically from $0.37$ at $s{=}0.15$ to $9.85$ at $s{=}0.30$. The monotonic growth of both the point estimate and the CI lower bound ($0.19 \\to 0.69 \\to 1.66 \\to 6.70$) confirms that compound severity amplification strengthens with sparsity---not merely in central tendency but also in worst-case lower bounds. Figure~\\ref{fig:permtest-forest} presents these results as a forest plot. % exp_id: deepseek_bf16_permtest; source: permutation_test_results.json\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Paired permutation test for compound severity: importance vs.\\ random eviction on DeepSeek-R1-Distill-Qwen-7B ($n{=}49$, $10{,}000$ permutations, Bonferroni-corrected).}\n\\label{tab:permutation}\n\\begin{tabular}{@{}rrcl@{}}\n\\toprule\n$s$ & Observed $\\widetilde{\\Delta}$ & 95\\% CI & $p_{\\text{Bonf}}$ \\\\\n\\midrule\n0.15 & 0.37 & $[0.19,\\; 0.62]$ & 0.0032 \\\\ % exp_id: deepseek_bf16_permtest_s015\n0.20 & 0.97 & $[0.69,\\; 1.49]$ & ${<}\\,0.001$ \\\\ % exp_id: deepseek_bf16_permtest_s020\n0.25 & 3.34 & $[1.66,\\; 6.64]$ & ${<}\\,0.001$ \\\\ % exp_id: deepseek_bf16_permtest_s025\n0.30 & 9.85 & $[6.70,\\; 16.29]$ & ${<}\\,0.001$ \\\\ % exp_id: deepseek_bf16_permtest_s030\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig4_bootstrap.pdf}\n\\caption{Forest plot of permutation test results. Horizontal bars show 95\\% permutation CIs; diamonds mark observed median differences $\\widetilde{\\Delta}$. All CIs lie entirely above zero, confirming significant strategy-dependent severity at every sparsity level.}\n\\label{fig:permtest-forest}\n\\end{figure}\n\n\n\\section{Analysis: Entropy-Discrimination Collapse}\n\\label{app:analysis}\n\n\\subsection{Discrimination Collapse}\n\\label{sec:discrimination-collapse}\n\nHead pruning reduces the number of heads contributing to cumulative importance scores, flattening the score distribution. Table~\\ref{tab:discrimination-metrics-full} quantifies this effect: the Gini coefficient decreases by $0.030$--$0.081$ (DeepSeek) and $0.010$--$0.020$ (Qwen) after pruning, with consistent negative deltas across all 16 conditions (both models $\\times$ 4 sparsity levels $\\times$ 2 strategies). The CV delta is likewise negative in all 8 importance-based conditions. The same pattern holds under random eviction, confirming that discrimination collapse is a consequence of head pruning \\emph{per se}, not of the eviction strategy. % exp_id: c4_entropy_deepseek, c4_entropy_qwen\n\n\\begin{table}[t]\n\\centering\n\\caption{Discrimination collapse under importance-based eviction. $\\Delta\\mathrm{Gini}$ and $\\Delta\\mathrm{CV}$ are post-pruning minus baseline; negative values indicate reduced discriminative power.}\n\\label{tab:discrimination-metrics-full}\n\\small\n\\begin{tabular}{llrr}\n\\toprule\nModel & $s$ & $\\Delta\\mathrm{Gini}$ & $\\Delta\\mathrm{CV}$ \\\\\n\\midrule\nDeepSeek & $0.15$ & $-0.030$ & $-0.56$ \\\\\nDeepSeek & $0.20$ & $-0.040$ & $-0.77$ \\\\\nDeepSeek & $0.25$ & $-0.065$ & $-1.29$ \\\\\nDeepSeek & $0.30$ & $-0.081$ & $-1.66$ \\\\\n\\midrule\nQwen & $0.15$ & $-0.010$ & $-0.05$ \\\\\nQwen & $0.20$ & $-0.012$ & $-0.21$ \\\\\nQwen & $0.25$ & $-0.010$ & $-1.49$ \\\\\nQwen & $0.30$ & $-0.020$ & $-1.14$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nWhen importance scores lose discriminability, thresholding degenerates into noise-sensitive selection---functionally approaching biased random eviction. This is phase-dependent: in low-sparsity phases, attention is already broadly distributed, so pruning-induced flattening has maximum impact; in high-sparsity phases, concentration is preserved. Random eviction is immune because its decisions are independent of score quality, explaining $G \\approx 1$. % exp_id: c4_entropy_deepseek, c4_entropy_qwen\n\n\\subsection{Entropy Redistribution}\n\\label{sec:entropy-redistribution}\n\nBeyond discrimination collapse, we examine whether head pruning also redistributes the attention entropy of surviving heads. We measure the mean attention entropy per head:\n\\begin{equation}\n    \\mathcal{H}_i^{(h)} = -\\sum_{j=1}^{T} a_{ij}^{(h)} \\log a_{ij}^{(h)}\n    \\label{eq:attn-entropy}\n\\end{equation}\nand compute $\\Delta\\mathcal{H}$ as the change from baseline (no pruning) to the pruned condition.\n\nFor DeepSeek under importance-based eviction, the entropy delta is consistently negative across all four sparsity levels ($\\Delta\\mathcal{H} \\in [-0.047, -0.040]$; Table~\\ref{tab:entropy-deltas}), indicating that importance-based pruning systematically selects heads whose removal concentrates attention in the surviving heads, reinforcing discrimination collapse. % exp_id: c4_entropy_deepseek\n\nFor Qwen, the entropy pattern only partially replicates. The delta is negative at $s{=}0.15$ ($\\Delta\\mathcal{H} = -0.073$) and $s{=}0.20$ ($-0.076$), consistent with DeepSeek. However, at $s{=}0.25$, the delta reverses to $+0.045$, with 22 of 30 problems showing positive entropy change. At $s{=}0.30$, the delta is near zero ($-0.007$). The $s{=}0.25$ reversal is systematic rather than a statistical artifact: it is consistent across all three reasoning phases (low: $+0.042$, mid: $+0.034$, high: $+0.017$). We interpret this as a genuine model-specific difference, possibly arising from distinct head specialization patterns: Qwen's instruction tuning (vs.\\ DeepSeek's distillation-based training) may produce head configurations where removing 25\\% of heads triggers compensatory broadening rather than concentration. % exp_id: c4_entropy_qwen\n\nWe characterize discrimination collapse as the robust, model-independent driver of the phase-strategy interaction, with entropy redistribution as a secondary amplifier that is consistent in DeepSeek but model-dependent in Qwen.\n\n\\begin{table}[t]\n\\centering\n\\caption{Attention entropy deltas ($\\Delta\\mathcal{H}$) under importance-based eviction. DeepSeek shows consistent entropy compression; Qwen partially replicates with a reversal at $s{=}0.25$.}\n\\label{tab:entropy-deltas}\n\\small\n\\begin{tabular}{llr}\n\\toprule\nModel & $s$ & $\\Delta\\mathcal{H}$ \\\\\n\\midrule\nDeepSeek & $0.15$ & $-0.040$ \\\\\nDeepSeek & $0.20$ & $-0.047$ \\\\\nDeepSeek & $0.25$ & $-0.045$ \\\\\nDeepSeek & $0.30$ & $-0.044$ \\\\\n\\midrule\nQwen & $0.15$ & $-0.073$ \\\\\nQwen & $0.20$ & $-0.076$ \\\\\nQwen & $0.25$ & $+0.045$ \\\\\nQwen & $0.30$ & $-0.007$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n",
      "numLines": 164,
      "startLine": 1,
      "totalLines": 164
    }
  }
}
```

</details>

---

### Tool call

_source line 39_

<details open><summary>🔧 Tool call — Read · `toolu_01DEbDLC5DP6hcQVphkQGJbk`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix_disc_analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "2c031181-5628-4c8d-9dec-ff5d68374798",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SY4memYbF781ZhkD6CTVAT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1425,
      "cache_read_input_tokens": 23417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1425
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

_source line 40 · 2026-05-14T20:44:03.850Z_

<details><summary>↩ Tool result · `toolu_01DEbDLC5DP6hcQVphkQGJbk`</summary>

```text
1	\section{Discrimination Collapse Details}
2	\label{app:discrimination-collapse-details}
3	
4	This cross-model consistency (Table~\ref{tab:discrimination-metrics-full}) establishes discrimination collapse as a robust consequence of compound sparsity. When importance scores lose discriminative power, thresholding the bottom-$s$ fraction becomes noise-sensitive: small perturbations change which positions cross the eviction boundary. In the limit of perfectly uniform scores, importance-based eviction degenerates into an arbitrary selection functionally equivalent to biased random eviction. The same pattern holds under random eviction (DeepSeek: $-0.031$ to $-0.073$; Qwen: $-0.019$ to $-0.045$), confirming that discrimination collapse is a consequence of head pruning \emph{per se}, not of the eviction strategy. % exp_id: c4_entropy_deepseek, c4_entropy_qwen
5	
6	
7	\section{Extended Discussion}
8	\label{app:extended-discussion}
9	
10	\paragraph{On the predictability of phase-modulated severity.}
11	The compound interaction is not uniformly fragile---it is selectively fragile in a phase-dependent manner ($\widetilde{\mathrm{II}}_{\text{high}} < 0.06$ at $s \leq 0.30$; at $s = 0.35$, high-phase II rises to $0.105$ in a supplementary experiment, indicating onset of compound interaction even in high-sparsity phases at extreme pruning rates). % exp_id: bf16_importance_s015..s030, bf16_ds_imp_s035; high-phase medians: 0.006, 0.015, 0.032, 0.053; s035 II_high=0.1051
12	
13	\paragraph{Random masking as falsification control.}
14	Random eviction fails 7/8 paired permutation tests across both models; the single exception (Qwen $s{=}0.30$, $p{=}0.012$) exhibits negligible effect size ($d_z{=}{-}0.04$). The absence of a phase gradient under random masking isolates the amplification as strategy-specific. % exp_id: bf16_ds_rand_s015..s030, bf16_qw_rand_s015..s030
15	
16	\paragraph{Entropy mechanism boundary conditions.}
17	Directly measuring per-head entropy shifts across architecturally distinct models---and identifying what training-time properties determine whether entropy concentrates or disperses under head pruning---would clarify the boundary conditions of the full mechanism.
18	
19	
20	\section{Extended Limitations}
21	\label{app:limitations}
22	
23	\paragraph{Model scale.}
24	All experiments are conducted at the 7B parameter scale.
25	Whether the phase-modulated severity patterns persist, amplify, or attenuate at larger scales (e.g., 70B) remains untested.
26	Larger models may exhibit different attention redundancy structures that alter the discrimination collapse dynamics (and the model-dependent entropy component may behave differently at scale).
27	% REVIEWER-ATTACK: "7B is too small to be relevant for production."
28	% REBUTTAL: 7B is the most-deployed scale for on-device and cost-constrained serving—exactly where compound sparsity is needed. The mechanism (entropy-discrimination collapse) is scale-agnostic in principle. Scaling experiments are future work.
29	
30	\paragraph{Architectural scope.}
31	Our two models---DeepSeek-R1-Distill-Qwen-7B and Qwen2.5-7B-Instruct---share the Qwen2ForCausalLM architecture.
32	The cross-model replication (\S\ref{sec:cross-model}) establishes that the findings are not artifacts of a single model's weights, though both models share the same Qwen2ForCausalLM architecture.
33	Cross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM, \S\ref{sec:cross-arch}) provides partial support: the directional pattern is qualitatively consistent but the interaction magnitude is substantially weaker than in Qwen2-based architectures, and random pruning also exhibits a non-trivial phase gradient on LLaMA. Further validation on more diverse architectures (e.g., Mistral, multi-latent attention architectures) is needed to establish the generality of the full interaction.
34	% REVIEWER-ATTACK: "Cross-model ≠ cross-architecture. Both are Qwen2ForCausalLM."
35	% REBUTTAL: We now include cross-architecture validation on LlamaForCausalLM (\S\ref{sec:cross-arch}), which shows a qualitatively consistent but substantially weaker pattern. We use qualified language ("partially supports") rather than claiming full generalization.
36	
37	\paragraph{Task coverage.}
38	We evaluate exclusively on MATH-500, a mathematical reasoning benchmark.
39	Different reasoning tasks---code generation, commonsense reasoning, multi-hop question answering---may induce different phase structures with different sparsity distributions, potentially altering the severity gradient profile.
40	Generalizing the phase-strategy interaction to broader reasoning domains is an important next step.
41	% REVIEWER-ATTACK: "Only MATH-500. How do we know this isn't a math-specific artifact?"
42	% REBUTTAL: The mechanism (entropy-discrimination collapse under head pruning) depends on attention distribution properties, not math-specific features. MATH-500 is a standard benchmark with diverse difficulty. However, different reasoning tasks may induce different phase structures—we state this limitation explicitly rather than overclaiming.
43	
44	\paragraph{Statistical scope.}
45	Bootstrap confidence intervals use $B{=}10{,}000$ resamples. The paired permutation test yields $n{=}49$ paired problems for DeepSeek (1 excluded) and $n{=}46$ for Qwen (4 excluded). % exp_id: cohens_d_bf16.json, cohens_d_bf16_qwen.json
46	The severity difference distribution is right-skewed (mean/median ratio ${\sim}1.6{:}1$ at $s{=}0.30$), motivating our use of medians and nonparametric tests rather than parametric alternatives. % exp_id: bf16_importance_s030; mean_diff=22.94, median_diff=14.59 (segment-level). Per-problem paired: median_diff=9.9436 at s030
47	All four permutation tests reject $H_0$ after Bonferroni correction ($p_{\text{Bonf}} < 0.005$; Table~\ref{tab:permutation}), with CI lower bounds increasing from $0.19$ to $6.70$---confirming the effect direction at every sparsity level. The permutation CIs at higher sparsity are wider (e.g., $[6.70,\; 16.29]$ at $s{=}0.30$), reflecting genuine variance in per-problem severity amplification. % exp_id: permutation_test_results.json; permutation CIs: s015=[0.19,0.62], s020=[0.69,1.49], s025=[1.66,6.64], s030=[6.70,16.29]
48	
49	A notable exception among the random baselines is the Qwen random condition at $s{=}0.30$, which yields a statistically significant result ($p{=}0.012$) despite negligible effect size ($d_z{=}{-}0.04$, bootstrap CI excluding zero). % exp_id: qw_rand_s030; B=10000, p=0.012, d=-0.035, negligible
50	This case illustrates that dichotomous significance testing can flag effects of no practical magnitude---reinforcing the importance of reporting effect sizes and confidence intervals alongside $p$-values.
51	
52	\paragraph{Sparsity range.}
53	Our experiments span $s \in \{0.15, 0.20, 0.25, 0.30\}$, a moderate range representative of practical deployment targets.
54	More extreme sparsity ($s > 0.50$) may exhibit qualitatively different interaction dynamics---the sub-exponential growth pattern suggests the severity gradient may plateau, but this remains unverified.
55	Conversely, the lower boundary at which phase-modulated amplification first emerges is not yet characterized.
56	% REVIEWER-ATTACK: "Why not test higher sparsity? 0.30 is conservative."
57	% REBUTTAL: Our focus is on the practically relevant regime where models retain usable quality. At s>0.30 both strategies degrade severely, making II measurement less informative. The sub-exponential growth (C6, $\Delta$ growth rate $3.8{\times} \to 4.8{\times} \to 2.0{\times}$) suggests saturation at higher sparsity, but confirming this is future work.
58	
59	\paragraph{No throughput evaluation.}
60	We do not report inference throughput or latency, which are necessary for deployment analysis but orthogonal to our severity characterization.
61	% REVIEWER-ATTACK: "No system evaluation. How do we know the severity amplification matters for real deployment?"
62	% REBUTTAL: This is an empirical finding paper, not a method/system paper. The contribution is characterizing *what happens* (phase-modulated severity) and *why* (entropy-discrimination collapse), not building a system to fix it. Phase-gated controllers are explicitly scoped as future work. The finding is actionable regardless: any compound sparsity deployment should be aware of phase-dependent severity.
63	
64	% Entropy redistribution analysis moved to main text \S\ref{sec:entropy-redistribution}
65	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "348a7c16-797e-4c25-878e-dfa238d31dc9",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix_disc_analysis.tex",
      "content": "\\section{Discrimination Collapse Details}\n\\label{app:discrimination-collapse-details}\n\nThis cross-model consistency (Table~\\ref{tab:discrimination-metrics-full}) establishes discrimination collapse as a robust consequence of compound sparsity. When importance scores lose discriminative power, thresholding the bottom-$s$ fraction becomes noise-sensitive: small perturbations change which positions cross the eviction boundary. In the limit of perfectly uniform scores, importance-based eviction degenerates into an arbitrary selection functionally equivalent to biased random eviction. The same pattern holds under random eviction (DeepSeek: $-0.031$ to $-0.073$; Qwen: $-0.019$ to $-0.045$), confirming that discrimination collapse is a consequence of head pruning \\emph{per se}, not of the eviction strategy. % exp_id: c4_entropy_deepseek, c4_entropy_qwen\n\n\n\\section{Extended Discussion}\n\\label{app:extended-discussion}\n\n\\paragraph{On the predictability of phase-modulated severity.}\nThe compound interaction is not uniformly fragile---it is selectively fragile in a phase-dependent manner ($\\widetilde{\\mathrm{II}}_{\\text{high}} < 0.06$ at $s \\leq 0.30$; at $s = 0.35$, high-phase II rises to $0.105$ in a supplementary experiment, indicating onset of compound interaction even in high-sparsity phases at extreme pruning rates). % exp_id: bf16_importance_s015..s030, bf16_ds_imp_s035; high-phase medians: 0.006, 0.015, 0.032, 0.053; s035 II_high=0.1051\n\n\\paragraph{Random masking as falsification control.}\nRandom eviction fails 7/8 paired permutation tests across both models; the single exception (Qwen $s{=}0.30$, $p{=}0.012$) exhibits negligible effect size ($d_z{=}{-}0.04$). The absence of a phase gradient under random masking isolates the amplification as strategy-specific. % exp_id: bf16_ds_rand_s015..s030, bf16_qw_rand_s015..s030\n\n\\paragraph{Entropy mechanism boundary conditions.}\nDirectly measuring per-head entropy shifts across architecturally distinct models---and identifying what training-time properties determine whether entropy concentrates or disperses under head pruning---would clarify the boundary conditions of the full mechanism.\n\n\n\\section{Extended Limitations}\n\\label{app:limitations}\n\n\\paragraph{Model scale.}\nAll experiments are conducted at the 7B parameter scale.\nWhether the phase-modulated severity patterns persist, amplify, or attenuate at larger scales (e.g., 70B) remains untested.\nLarger models may exhibit different attention redundancy structures that alter the discrimination collapse dynamics (and the model-dependent entropy component may behave differently at scale).\n% REVIEWER-ATTACK: \"7B is too small to be relevant for production.\"\n% REBUTTAL: 7B is the most-deployed scale for on-device and cost-constrained serving—exactly where compound sparsity is needed. The mechanism (entropy-discrimination collapse) is scale-agnostic in principle. Scaling experiments are future work.\n\n\\paragraph{Architectural scope.}\nOur two models---DeepSeek-R1-Distill-Qwen-7B and Qwen2.5-7B-Instruct---share the Qwen2ForCausalLM architecture.\nThe cross-model replication (\\S\\ref{sec:cross-model}) establishes that the findings are not artifacts of a single model's weights, though both models share the same Qwen2ForCausalLM architecture.\nCross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM, \\S\\ref{sec:cross-arch}) provides partial support: the directional pattern is qualitatively consistent but the interaction magnitude is substantially weaker than in Qwen2-based architectures, and random pruning also exhibits a non-trivial phase gradient on LLaMA. Further validation on more diverse architectures (e.g., Mistral, multi-latent attention architectures) is needed to establish the generality of the full interaction.\n% REVIEWER-ATTACK: \"Cross-model ≠ cross-architecture. Both are Qwen2ForCausalLM.\"\n% REBUTTAL: We now include cross-architecture validation on LlamaForCausalLM (\\S\\ref{sec:cross-arch}), which shows a qualitatively consistent but substantially weaker pattern. We use qualified language (\"partially supports\") rather than claiming full generalization.\n\n\\paragraph{Task coverage.}\nWe evaluate exclusively on MATH-500, a mathematical reasoning benchmark.\nDifferent reasoning tasks---code generation, commonsense reasoning, multi-hop question answering---may induce different phase structures with different sparsity distributions, potentially altering the severity gradient profile.\nGeneralizing the phase-strategy interaction to broader reasoning domains is an important next step.\n% REVIEWER-ATTACK: \"Only MATH-500. How do we know this isn't a math-specific artifact?\"\n% REBUTTAL: The mechanism (entropy-discrimination collapse under head pruning) depends on attention distribution properties, not math-specific features. MATH-500 is a standard benchmark with diverse difficulty. However, different reasoning tasks may induce different phase structures—we state this limitation explicitly rather than overclaiming.\n\n\\paragraph{Statistical scope.}\nBootstrap confidence intervals use $B{=}10{,}000$ resamples. The paired permutation test yields $n{=}49$ paired problems for DeepSeek (1 excluded) and $n{=}46$ for Qwen (4 excluded). % exp_id: cohens_d_bf16.json, cohens_d_bf16_qwen.json\nThe severity difference distribution is right-skewed (mean/median ratio ${\\sim}1.6{:}1$ at $s{=}0.30$), motivating our use of medians and nonparametric tests rather than parametric alternatives. % exp_id: bf16_importance_s030; mean_diff=22.94, median_diff=14.59 (segment-level). Per-problem paired: median_diff=9.9436 at s030\nAll four permutation tests reject $H_0$ after Bonferroni correction ($p_{\\text{Bonf}} < 0.005$; Table~\\ref{tab:permutation}), with CI lower bounds increasing from $0.19$ to $6.70$---confirming the effect direction at every sparsity level. The permutation CIs at higher sparsity are wider (e.g., $[6.70,\\; 16.29]$ at $s{=}0.30$), reflecting genuine variance in per-problem severity amplification. % exp_id: permutation_test_results.json; permutation CIs: s015=[0.19,0.62], s020=[0.69,1.49], s025=[1.66,6.64], s030=[6.70,16.29]\n\nA notable exception among the random baselines is the Qwen random condition at $s{=}0.30$, which yields a statistically significant result ($p{=}0.012$) despite negligible effect size ($d_z{=}{-}0.04$, bootstrap CI excluding zero). % exp_id: qw_rand_s030; B=10000, p=0.012, d=-0.035, negligible\nThis case illustrates that dichotomous significance testing can flag effects of no practical magnitude---reinforcing the importance of reporting effect sizes and confidence intervals alongside $p$-values.\n\n\\paragraph{Sparsity range.}\nOur experiments span $s \\in \\{0.15, 0.20, 0.25, 0.30\\}$, a moderate range representative of practical deployment targets.\nMore extreme sparsity ($s > 0.50$) may exhibit qualitatively different interaction dynamics---the sub-exponential growth pattern suggests the severity gradient may plateau, but this remains unverified.\nConversely, the lower boundary at which phase-modulated amplification first emerges is not yet characterized.\n% REVIEWER-ATTACK: \"Why not test higher sparsity? 0.30 is conservative.\"\n% REBUTTAL: Our focus is on the practically relevant regime where models retain usable quality. At s>0.30 both strategies degrade severely, making II measurement less informative. The sub-exponential growth (C6, $\\Delta$ growth rate $3.8{\\times} \\to 4.8{\\times} \\to 2.0{\\times}$) suggests saturation at higher sparsity, but confirming this is future work.\n\n\\paragraph{No throughput evaluation.}\nWe do not report inference throughput or latency, which are necessary for deployment analysis but orthogonal to our severity characterization.\n% REVIEWER-ATTACK: \"No system evaluation. How do we know the severity amplification matters for real deployment?\"\n% REBUTTAL: This is an empirical finding paper, not a method/system paper. The contribution is characterizing *what happens* (phase-modulated severity) and *why* (entropy-discrimination collapse), not building a system to fix it. Phase-gated controllers are explicitly scoped as future work. The finding is actionable regardless: any compound sparsity deployment should be aware of phase-dependent severity.\n\n% Entropy redistribution analysis moved to main text \\S\\ref{sec:entropy-redistribution}\n",
      "numLines": 65,
      "startLine": 1,
      "totalLines": 65
    }
  }
}
```

</details>

---

### Assistant

_source line 41_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the tex files. Let me also read the decisions file to understand D054, D059, D015, D056, D060 constraints better, and check if there are figures referenced.

Let me now systematically go through each section and identify all n=50 data points that need updating for n=500.

Let me organize my findings:

## Abstract (abstract.tex)
1. Line 6: "50 MATH-500 problems" → n=500
2. Line 7: "median Interaction Index difference...increases monotonically from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$" → update numbers


3. Line 7: "$d_z$ growing from $0.44$ (small) to $0.80$ (large)" → update
4. Line 7: "Bonferroni-corrected permutation tests yield $p < 0.005$" → update p-values
5. Line 8: "Random eviction produces no significant phase modulation in 7/8 conditions" → update ratio
6. Line 8: "Qwen $s{=}0.30$, $p{=}0.012$" → update
7. Line 8: "$d_z{=}{-}0.04$" → update
8. Line 9: continuing through the remaining statistical values and crossover numbers that need adjustment

, then moving into the Introduction section where I'm updating effect sizes and parameter ranges starting from line 14.

Now I'm working through the Introduction updates, adjusting the range of values from 0.39 to 14.59 across different sparsity levels, along with the corresponding effect sizes and statistical significance thresholds. I need to revise the magnitude ratios and update which conditions showed significant effects.

For the Methodology section, I'm noting that the problem set comes from MATH-500, updating the skewness statistics that explain why medians are more appropriate than means given the heavy right-skewed distribution, and confirming that the Bonferroni-corrected significance threshold holds across all sparsity levels.

Now I'm updating the Results section with the new amplification factors and ranges for the main findings, revising the aggregate table values, and adjusting the high-end estimates for the information integration metric across the different sparsity conditions. Continuing through the statistical updates needed across lines 71-79, including Spearman correlation coefficients, effect sizes with confidence intervals, and sample sizes for the paired problem analysis. I'm continuing through the statistical updates needed in the results section, working through effect sizes and confidence intervals across different model comparisons. Now I need to regenerate the crossover and cross-model figures, then move into the analysis section where there are additional numerical values to update starting with DeepSeek performance metrics. I'm going through the conclusion section now, checking which numerical values and statistical findings need updating—the effect sizes, significance thresholds, and comparative metrics across all the conditions we tested. I'm continuing through the appendix_moved.tex file, noting more numerical values and figures that need updating—crossover multipliers, sample size exclusions, cross-model comparisons, and statistical metrics throughout the document.

Now moving into the appendix_disc_analysis.tex section, where I need to update coefficient ranges for different models and adjust threshold values and statistical measures.

Continuing through the remaining updates: I'm checking specific p-values and effect sizes that appear in multiple locations, updating permutation confidence intervals, and revising the sparsity growth rate comparisons across different scaling factors.

I also need to verify a hard constraint about how information integration metrics should be reported—specifically that only median values with bootstrap confidence intervals should be used, not means, which I can confirm is consistent with the methodology section's discussion of the extreme ratio disparities between mean and median calculations.

Now I'm examining another constraint about effect size reporting. The d_z metric should only appear in within-importance scenarios, not when comparing importance-based versus random severity approaches. Looking at the LLaMA cross-architecture table, I see it's reporting d_z for an importance versus random comparison, which would violate this constraint. The other table with paired d_z values for phase-dependent metrics under importance-based eviction is fine, but I need to flag the LLaMA table as problematic. Looking at the table caption more carefully, it explicitly states the d_z is for "importance vs. random severity" - that's a direct violation of D059, which requires reporting only within-importance d_z values. This needs to be flagged as a structural change required for the update. I'm also scanning through the paper's framing to verify D015 compliance - the language around "emergent phase-strategy interaction" appears consistent throughout, and I need to check whether C5b content has been properly moved to the future work section as indicated by D056. I'm noticing the language around the LLaMA results needs to be more careful—"replicates" in the Results section might be overstating the evidence when the constraint requires "suggests" or "provides partial support" for cross-architecture claims. I should flag that the Results section uses stronger language than what's justified, especially since the Discussion and Conclusion already use the appropriately cautious framing. I also need to check the framing around random initialization having positive II and how that's being presented.

Now I'm compiling which figures need regeneration with the n=50 dataset and reviewing the LLaMA within-importance values to ensure they're correctly reported.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "02446833-3ce6-44ab-afa8-bcc4b7aec888",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NsNzGGJTnvwdDGj7n9Dukr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 34963,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 34963
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

_source line 42_

所有 tex 文件已读取。现在逐 section 系统扫描，产出更新清单。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "845e979f-43e6-46d6-8a1e-18732ff00ed8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NsNzGGJTnvwdDGj7n9Dukr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 34963,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 34963
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

_source line 43_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01V6MQAjct3tYKQeV1m87sF4`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__append_idea",
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
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "5ce3f385-56d7-44c6-baed-00e27163bf6f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NsNzGGJTnvwdDGj7n9Dukr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 34963,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 34963
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

_source line 44 · 2026-05-14T20:45:40.685Z_

<details><summary>↩ Tool result · `toolu_01V6MQAjct3tYKQeV1m87sF4`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__append_idea"
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
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "ed09d6f1-5d46-41a1-93bc-575d43879a3d",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__append_idea"
    ],
    "query": "select:mcp__agent-ml-research__append_idea",
    "total_deferred_tools": 26
  }
}
```

</details>

---

### Assistant

_source line 45_

<details><summary>Logged reasoning block</summary>

```text
Now let me compile the comprehensive checklist. I need to go through every section systematically and identify all places that need updating. Let me also check the decisions referenced in the hard constraints by reading the decisions file.

Let me first check the decisions file to understand D054, D059, D015, D056, D060 better.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "5ea7b92f-1844-41de-a5d7-d49bc38491c5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VhUTrcoNVyWqGiGjkfncjv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 4855,
      "cache_read_input_tokens": 46410,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4855
      },
      "output_tokens": 28,
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

_source line 46_

先读取 decisions 文件确认硬约束细节，再产出完整清单。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "ca998310-1e67-486d-b323-cd4feee600df",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VhUTrcoNVyWqGiGjkfncjv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 4855,
      "cache_read_input_tokens": 46410,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4855
      },
      "output_tokens": 28,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01GDCcY8WZZoukDR1ECdb8Ln`</summary>

```json
{
  "project": "phase-gated-compound-sparse",
  "file": "decisions.yaml",
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
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "62cfea77-5fa8-4d54-b687-6357d4e61c79",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VhUTrcoNVyWqGiGjkfncjv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 4855,
      "cache_read_input_tokens": 46410,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4855
      },
      "output_tokens": 28,
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

_source line 48 · 2026-05-14T20:45:46.179Z_

<details><summary>↩ Tool result · `toolu_01GDCcY8WZZoukDR1ECdb8Ln`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/decisions.yaml\", \"content\": \"_next_id: 63\\ndecisions:\\n- id: D001\\n  date: 2026-05-13 17:44 UTC\\n  summary: MVP 方案：用 Interaction Index 跨 phase 差异验证核心假设\\n  rationale: 评审建议 novelty 锚定在 \\\"phase-dependent interaction direction reversal\\\"。MVP\\n    聚焦验证这一点：在 MATH-500 子集上 profiling DeepSeek-R1-Distill-Qwen-7B，用 ThinKV 方法切分 phases，计算\\n    attention × KV 的 Interaction Index。比全 grid search 更聚焦，直接验证核心 novelty 锚点。Pass =\\n    II 跨 phase 显著不同；Fail = II 恒定。预计 10-15 H100-hours。\\n  related_experiments: []\\n  depends_on: []\\n- id: D002\\n  date: 2026-05-13 17:48 UTC\\n  summary: 向 Manager 申请 4×H100-80GB 租卡，预计 8-10 天，¥3200-5000\\n  rationale: 12 天截稿，4 GPU 并行可将日历时间压到 ~8 天（留 4 天 buffer）。2 GPU 需 11 天，buffer 不足 1 天，风险过高。用户明确授权\\\"几张都可以\\\"。GPU\\n    就绪 hard deadline 5/14 EOD。\\n  related_experiments: []\\n  depends_on:\\n  - D001\\n- id: D003\\n  date: 2026-05-13 17:54 UTC\\n  summary: Throughput 策略：RTX 6000 Pro 做开发/accuracy，最终 throughput 短租 H100\\n  rationale: IDEA_BRIEF 硬约束要求\\\"Report wall-clock and throughput on H100\\\"，baseline 论文（Polar\\n    Sparsity、SeerAttention-R）均报告 H100 数字。RTX 6000 Pro (sm_89) vs H100 (sm_90) 的 kernel\\n    speedup 可能不同。策略(a)：RTX 6000 Pro 做全部开发+accuracy+ablation（硬件无关），仅 throughput 基准测试短租\\n    H100 ~2-4h（~$6-12）。比策略(b)全在 RTX 6000 Pro 上报告更有说服力，成本极低。H100 在 M5 阶段再申请。\\n  related_experiments: []\\n  depends_on:\\n  - D002\\n- id: D004\\n  date: 2026-05-13 17:58 UTC\\n  summary: Throughput benchmark 硬件从 H100 改为 H20（Hopper sm_90，用户确认无 H100 可用）\\n  rationale: H20 与 H100 同为 Hopper sm_90，kernel 兼容无需额外适配。96GB HBM3 + 4TB/s 带宽适合 inference\\n    benchmark。在 H20 上重跑所有 baseline 确保公平比较，报告 relative speedup ratio（Hopper 架构内比值稳定）。H100\\n    不可用，H20 是最佳替代。\\n  related_experiments: []\\n  depends_on:\\n  - D003\\n- id: D005\\n  date: 2026-05-13 18:01 UTC\\n  summary: GPU 从 4× RTX 6000 Pro 换为 4× H20-NVLink 96GB\\n  rationale: H20 是 Hopper sm_90（与 H100 同架构），kernel 无需跨架构适配。4TB/s HBM3 带宽远优于 RTX 6000\\n    Pro（~960GB/s），7B 推理速度接近 H100。全程同架构消除 M5+ 短租需求，简化流程。用户主动提出可换 H20。\\n  related_experiments: []\\n  depends_on:\\n  - D004\\n- id: D006\\n  date: 2026-05-13 18:40 UTC\\n  summary: GPU 实际为 Blackwell sm_100+（非 Ada sm_89）：MVP 不阻塞，kernel/throughput 阶段需 Hopper\\n  rationale: nvidia-smi 显示 \\\"RTX PRO 6000 Blackwell Server Edition\\\" compute cap 12.0。MVP\\n    profiling 仅需 PyTorch forward pass 无架构依赖。M4 kernel integration 阶段 Triton/TileLang\\n    对 sm_100+ 支持待验证。M5+ throughput benchmark 仍需 Hopper 架构（H20）做可比测量。先用 Blackwell 推进\\n    M1-M3，不阻塞。\\n  related_experiments: []\\n  depends_on:\\n  - D005\\n- id: D007\\n  date: 2026-05-13 20:20 UTC\\n  summary: M1 结果无效（KV bug + KDE 失败）：两路并行——P0 修复重跑 + 替代 segmentation 开发\\n  rationale: KV eviction 的 per-layer mask 交集 bug 导致全 NaN（P0），KDE 82% 样本找不到 tri-modal\\n    结构（P1）。但积极信号存在：execution phase 对 head pruning 敏感度 474× vs reasoning 14×，说明 token\\n    级结构性差异真实存在。决策：(A) P0 修复后重跑 M1 获取有效 II + 诊断数据，(B) 并行开发 GMM+BIC / quantile-based\\n    / multi-layer 替代 segmentation。先看重跑 II 是否在现有 3 phase 间有差异，差异显著则 KDE 虽粗糙但假设成立；无差异则上替代方案。\\n  related_experiments:\\n  - exp_id: mvp_interaction_index_profiling\\n    role: failed_run\\n    result: KV NaN + KDE 82% fallback + 90% transition\\n  depends_on:\\n  - D001\\n- id: D008\\n  date: 2026-05-13 21:23 UTC\\n  summary: M1v2 假设未获支持但测量方法有问题——M1v3 最后诊断：降 sparsity + quantile segmentation + NaN\\n    guard\\n  rationale: M1v2 所有 phase 均 super-additive、无 sign reversal，但 3 个方法论问题使结论不可靠：(1) 30%\\n    random masking 导致 24-33× PPL 退化，超出安全区；(2) KDE 90% fallback，phase 划分无意义；(3) NaN\\n    CI artifact 导致虚假 PASS。M1v3 修复这三点后做最终判定。叙事 pivot：即使全 super-additive，magnitude 跨\\n    segment 差异（+17.8 vs +3.1）仍支持 phase-aware allocation。Pass = magnitude CI 不重叠；Fail\\n    = magnitude 无差异。\\n  related_experiments:\\n  - exp_id: mvp_ii_profiling_v2\\n    role: diagnostic\\n    result: All super-additive, no sign reversal, NaN artifact PASS, KDE 90% fallback\\n  depends_on:\\n  - D007\\n- id: D009\\n  date: 2026-05-13 22:44 UTC\\n  summary: Random masking 系统性混淆——v1-v3 测了错误条件；importance-based masking 是正确 MVP 测试，立即启动\\n    v4\\n  rationale: 三次 MVP 实验全用 random masking（torch.randperm 选 heads/KV），天然产生 super-additive\\n    interaction（随机移除组件造成相关性损伤）。初步 importance-vs-random 对比已显示 masking 方法是 II 符号的主导因子（importance\\n    II=-0.91 sub-additive vs random II=+9.38 super-additive）。v3 在 clean methodology\\n    下仍全 super-additive 是预期结果，不代表 PACS 假设无效。真正的 MVP 判定需在 importance-based masking 条件下测试\\n    per-phase II——这才是实际部署条件下的 compound sparsity 行为。v3 high vs mid 在 s=0.2 下 CI 几乎不重叠（[1.06,3.55]\\n    vs [-1.06,1.30]），暗示 importance-based 下 magnitude 差异可能更显著。\\n  related_experiments:\\n  - exp_id: mvp_ii_profiling_v3\\n    role: evidence\\n    result: negative under random masking, but confirms methodology is sound\\n  - exp_id: mvp_ii_profiling_v2\\n    role: evidence\\n    result: negative, methodology issues identified and fixed in v3\\n  - exp_id: mvp_interaction_index_profiling\\n    role: evidence\\n    result: failed (bugs), but importance-vs-random preliminary data is key signal\\n  depends_on:\\n  - D008\\n- id: D010\\n  date: 2026-05-13 22:44 UTC\\n  summary: MVP FAIL on phase-dependent reversal; PIVOT to strategy-dependent direction\\n    reversal as core novelty\\n  rationale: 三轮 MVP 实验（v1 bug/v2 negative/v3 negative）确认 phase-dependent direction\\n    reversal 不存在——所有 phase 均 super-additive，v2 的 5.8x magnitude 差异是 KDE 不均衡 artifact。但\\n    importance vs random masking 数据发现 strategy-dependent direction reversal：random\\n    30% II=+9.38（super-additive）vs importance 30% II=-0.91（sub-additive），20% 也有符号反转。这是更干净、更强的\\n    novelty 锚点，直接 motivate learned compound controller。Pivot 方向：以 strategy-dependent\\n    interaction reversal 为核心 claim，phase conditioning 降为可选的二级贡献。\\n  related_experiments:\\n  - exp_id: mvp_interaction_index_profiling\\n    role: initial MVP (bugged)\\n    result: failed\\n  - exp_id: mvp_ii_profiling_v2\\n    role: P0 fix rerun\\n    result: negative - no direction reversal\\n  - exp_id: mvp_ii_profiling_v3\\n    role: low sparsity + quantile segmentation\\n    result: negative - no magnitude difference\\n  depends_on:\\n  - D008\\n  - D007\\n  - D001\\n- id: D011\\n  date: 2026-05-14 01:00 UTC\\n  summary: Float16 NaN→II bias discovered at s≥0.3; fix to float32 forward, don't\\n    pause running batch\\n  rationale: Agent 发现 head masking hook 中 inf×0→NaN 导致高 sparsity 下 both_ppl 为 NaN，II\\n    聚合排除这些 segment 造成系统性偏差。当前 batch (s025/s035/v4d) 保持运行作为 float16 reference，并行实施\\n    float32 修复，完成后重跑。Random masking 不受影响。\\n  related_experiments:\\n  - exp_id: mvp_v4_legacy_s035\\n    role: affected\\n    result: running, float16 results may be biased\\n  - exp_id: mvp_ii_profiling_v4d\\n    role: affected\\n    result: running, float16 results may be biased\\n  - exp_id: mvp_v4_legacy_s025\\n    role: reference\\n    result: running, likely unaffected at s=0.25\\n  - exp_id: mvp_v4_random_r2\\n    role: control\\n    result: running, unaffected by this bug\\n  depends_on:\\n  - D010\\n- id: D012\\n  date: 2026-05-14 01:07 UTC\\n  summary: 暂停 importance-based 实验规划，紧急审查 KV importance metric 正确性\\n  rationale: 'Reviewer 发现 importance-based KV eviction 的 PPL 退化比 random eviction 严重\\n    26-60 倍（s=0.3: 408.98 vs 6.77），完全反直觉。cumulative_attention_received 作为 importance\\n    proxy 可能失效或排序方向有 bug。如果 metric 是坏的，D010 的 strategy-dependent direction reversal\\n    是 artifact 而非真实现象，整个 importance-based 路线需要重新评估。'\\n  related_experiments:\\n  - exp_id: mvp_v4_random_r2\\n    role: evidence\\n    result: random baseline 全 super-additive，数据可靠\\n  - exp_id: mvp_v4a_r2\\n    role: evidence\\n    result: importance-based kv_ppl 异常高，26-60x worse than random\\n  depends_on:\\n  - D010\\n- id: D013\\n  date: 2026-05-14 01:16 UTC\\n  summary: 暂停 importance masking 结论，根因确认：cumulative_attention_received 有因果注意力位置偏差，驱逐最近上下文导致灾难性退化\\n  rationale: Reviewer 根因分析确认：causal attention 中 position 0 被 N-1 个 token 关注（累积最高），position\\n    N-1 仅被自身关注（累积最低）。topk(largest=False) 驱逐最低分 = 驱逐最新位置 = 破坏最近上下文。这解释了 importance\\n    eviction 比 random 差 26-60× 的现象。s025 的 II per-sample mean (+152.7) 与聚合计算 (-107.6)\\n    符号相反，CI 宽 455 单位，统计意义为零。D010 的 strategy-dependent direction reversal 可能完全是坏指标伪影。修复方向：position\\n    normalization importance[j] /= (seq_len - j)。\\n  related_experiments:\\n  - exp_id: mvp_v4_legacy_s025\\n    role: evidence\\n    result: II=+152.7 但聚合计算=-107.6，符号矛盾\\n  - exp_id: mvp_v4_legacy_s035\\n    role: evidence\\n    result: II=-462.7, CI=[-1557,+101]，极不稳定\\n  - exp_id: mvp_ii_profiling_v4d\\n    role: failed\\n    result: 5/50后静默崩溃，疑似OOM\\n  depends_on:\\n  - D010\\n- id: D014\\n  date: 2026-05-14 02:19 UTC\\n  summary: D010 pivot hypothesis NEGATIVE; 新发现 phase-modulated severity gradient (28x-1633x);\\n    选定 Framing A 进入 research\\n  rationale: v5 修复后 4 个 sparsity level 全部 super-additive，strategy-dependent reversal\\n    不成立（v4 负值为 NaN 伪影）。但数据揭示更强信号：importance eviction 下 phase gradient 达 1633x（s=0.30），random\\n    仅 1.8x。这是无先行文献报告的 novel finding。选方案 A \\\"Phase-Modulated Compound Interaction Severity\\\"：(1)\\n    数据最强力支撑 (2) 与 SparK (AAAI'26) 差异化（他们没看 phase 维度）(3) 直接导出 phase-gated controller\\n    作为系统贡献。需注意 s=0.30 low phase 存在 heavy tail（mean=1926 vs median=44.63），论文需报告 robust\\n    statistics。\\n  related_experiments:\\n  - exp_id: mvp_v5_fixed_s015\\n    role: validation\\n    result: positive - phase gradient 28x\\n  - exp_id: mvp_v5_fixed_s020\\n    role: validation\\n    result: positive - phase gradient 64x\\n  - exp_id: mvp_v5_fixed_s025\\n    role: validation\\n    result: positive - phase gradient 114x\\n  - exp_id: mvp_v5_fixed_s030\\n    role: validation\\n    result: positive - phase gradient 1633x\\n  - exp_id: mvp_v4_random_r2\\n    role: baseline\\n    result: random gradient <2x across all sparsity\\n  depends_on:\\n  - D013\\n  - D010\\n- id: D015\\n  date: 2026-05-14 03:00 UTC\\n  summary: 'GO: Phase-modulated severity confirmed (median gradient 12.8x-74.9x importance\\n    vs ~1x random), proceed to M1'' bootstrap CI + cross-model'\\n  rationale: 四个 sparsity level 的 importance median gradient 单调递增（12.8x→28.7x→52.9x→74.9x），random\\n    baseline 恒定 ~1x。Phase-strategy interaction 是 importance masking 特异性现象，非 compound\\n    sparsity 通用属性。Crossover pattern（importance 在 high phase 更安全、low phase 更危险）提供额外\\n    motivation。Go/no-go 标准满足：importance median gradient 显著 > random median gradient。叙事锚定\\n    median（mean 因 s030 heavy tail 膨胀 21.8x）。\\n  related_experiments:\\n  - exp_id: mvp_v5_fixed_s015\\n    role: importance s=0.15\\n    result: median gradient 12.8x\\n  - exp_id: mvp_v5_fixed_s020_r2\\n    role: importance s=0.20\\n    result: median gradient 28.7x\\n  - exp_id: mvp_v5_fixed_s025\\n    role: importance s=0.25\\n    result: median gradient 52.9x\\n  - exp_id: mvp_v5_fixed_s030_r2\\n    role: importance s=0.30\\n    result: median gradient 74.9x\\n  - exp_id: mvp_v5_random_s015\\n    role: random baseline s=0.15\\n    result: gradient 1.14x\\n  - exp_id: mvp_v5_random_s025\\n    role: random baseline s=0.25\\n    result: gradient 0.97x\\n  depends_on:\\n  - D014\\n- id: D016\\n  date: 2026-05-14 03:00 UTC\\n  summary: 'D015: GO — Phase-modulated severity claim 验证通过，进入 M1'' bootstrap CI +\\n    cross-model'\\n  rationale: Importance median gradient 单调递增 12.8x→28.7x→52.9x→74.9x（4 sparsity levels），random\\n    baseline gradient ≈1x（phase-independent）。Importance/random gradient 比值 11.2x-54.5x，CI\\n    不重叠。核心 claim \\\"importance eviction 下 compound interaction 是 phase-dependent 的\\\"\\n    获实证支撑。叙事锚定 median（mean 因 heavy tail 膨胀，s030 mean/median=43:1）。附带发现：importance\\n    产生 phase-selective amplification（高 sparsity phase 反而减少交互，低 sparsity phase 大幅放大），强化\\n    phase-gated controller motivation。\\n  related_experiments:\\n  - exp_id: mvp_v5_fixed_s015\\n    role: importance s=0.15\\n    result: median gradient 12.8x\\n  - exp_id: mvp_v5_fixed_s020_r2\\n    role: importance s=0.20\\n    result: median gradient 28.7x\\n  - exp_id: mvp_v5_fixed_s025\\n    role: importance s=0.25\\n    result: median gradient 52.9x\\n  - exp_id: mvp_v5_fixed_s030_r2\\n    role: importance s=0.30\\n    result: median gradient 74.9x\\n  - exp_id: mvp_v5_random_s015\\n    role: random baseline s=0.15\\n    result: gradient 1.14x (phase-independent)\\n  - exp_id: mvp_v5_random_s025\\n    role: random baseline s=0.25\\n    result: gradient 0.97x (phase-independent)\\n  depends_on:\\n  - D014\\n- id: D017\\n  date: 2026-05-14 04:49 UTC\\n  summary: 'D017: Bootstrap CI confirms importance gradient 11-42× (all p=0.0000);\\n    launch cross-model + random re-run'\\n  rationale: v6 importance 四组 per-problem bootstrap (B=10000) 结果：paired gradient 11.5-41.9×,\\n    unpaired 12.7-39.3×, 所有 CI 下界远离 1.0, p=0.0000。Phase-modulated severity claim 统计显著成立。下一步：(1)\\n    Qwen2.5-7B cross-model 验证泛化性，(2) 用 v6 代码重跑 random 获取 per_problem_ii 做同粒度对比。论文主表用\\n    unpaired bootstrap（n 更大 CI 更窄），paired 放 appendix。4 GPU 并行：2 卡 Qwen importance\\n    + 2 卡 random re-run。\\n  related_experiments:\\n  - exp_id: v6_importance_s015\\n    role: primary\\n    result: gradient=11.53×, CI=[3.49,23.78]\\n  - exp_id: v6_importance_s020\\n    role: primary\\n    result: gradient=11.05×, CI=[5.42,69.27]\\n  - exp_id: v6_importance_s025\\n    role: primary\\n    result: gradient=35.72×, CI=[9.52,101.54]\\n  - exp_id: v6_importance_s030\\n    role: primary\\n    result: gradient=41.92×, CI=[19.14,299.76]\\n  depends_on:\\n  - D016\\n- id: D018\\n  date: 2026-05-14 05:24 UTC\\n  summary: Qwen 速度问题为误诊（实际 ~50s/problem），停止 Route B speed fix；NaN overlap 检查为 P0 阻塞项\\n  rationale: Reviewer 核实 Qwen 日志发现实际速度 ~50s/problem（与 DeepSeek 相当），之前 37-75min/problem\\n    的诊断错误。Kill Qwen 实验的决策基于错误前提。Route B worker 在解决不存在的问题，应停止。NaN overlap 检查决定是否需要\\n    bf16 全量重跑，是当前最高优先级阻塞项。\\n  related_experiments:\\n  - exp_id: qwen_importance_s015\\n    role: killed_误诊\\n    result: killed\\n  - exp_id: qwen_importance_s020\\n    role: killed_误诊\\n    result: killed\\n  - exp_id: qwen_importance_s025\\n    role: killed_误诊\\n    result: killed\\n  - exp_id: qwen_importance_s030\\n    role: killed_误诊\\n    result: killed\\n  depends_on:\\n  - D017\\n- id: D019\\n  date: 2026-05-14 05:31 UTC\\n  summary: bf16 全量重跑：NaN 过滤存在选择偏差（15.3% 不一致），fp16 结果不可用于论文 claim\\n  rationale: Reviewer 审查发现 s015 vs s030 中 23/150 对 null 状态不一致（ii_mid 不一致率 24%），NaN\\n    不仅来自 dense forward（Layer 27），还来自 sparse 条件本身。NaN 过滤会系统性丢弃 sparse 表现最差位置，导致 II\\n    估计偏低。bf16 5-problem 验证已通过（仅 1 个合法缺失）。当前 fp16 v6_random 让其跑完（sunk cost），但论文数据必须基于\\n    bf16 重跑版本。\\n  related_experiments:\\n  - exp_id: v6_importance_s015\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_importance_s020\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_importance_s025\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_importance_s030\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_random_s015\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_random_s020\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_random_s025\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_random_s030\\n    role: affected\\n    result: killed + fp16 NaN bias\\n  depends_on: []\\n- id: D020\\n  date: 2026-05-14 05:35 UTC\\n  summary: bf16 全量重跑：16 个实验（DeepSeek + Qwen × importance + random × 4 sparsity），论文数据统一\\n    bf16\\n  rationale: fp16 NaN 跨条件不一致率 15.3%（NaN overlap 检查确认），null-filter 后存在选择偏差。bf16 验证\\n    0 NaN。fp16 vs bf16 数值精度不同导致 token 序列差异，不可混用。全量重跑 ~3h，时间充裕。\\n  related_experiments:\\n  - exp_id: v6_importance_s015\\n    role: affected\\n    result: fp16 NaN 需重跑\\n  - exp_id: v6_importance_s020\\n    role: affected\\n    result: fp16 NaN 需重跑\\n  - exp_id: v6_importance_s025\\n    role: affected\\n    result: fp16 NaN 需重跑\\n  - exp_id: v6_importance_s030\\n    role: affected\\n    result: fp16 NaN 需重跑\\n  - exp_id: bf16_verify\\n    role: evidence\\n    result: bf16 消除 NaN，0/50\\n  - exp_id: qwen_pilot\\n    role: evidence\\n    result: Qwen bf16 同样 NaN-free\\n  depends_on: []\\n- id: D021\\n  date: 2026-05-14 05:53 UTC\\n  summary: 'Framing constraint D023: super-additivity claim must specify phase-dependent\\n    gradient, not mere existence'\\n  rationale: 'Reviewer 审查 v6_random_s020 发现 random masking 也产生正 II（mean ~0.9-1.3×），因此论文不能\\n    claim \\\"importance masking produces super-additive interaction\\\"——random 也有。区分信号是\\n    phase-dependent gradient（importance: 跨两个数量级 vs random: ~1× flat）。同时 high_sparsity\\n    skewness=-4.83 要求 permutation test 使用 robust statistic。'\\n  related_experiments:\\n  - exp_id: v6_random_s020\\n    role: evidence\\n    result: random II positive (~0.9-1.3×) but no phase-dependent gradient — expected\\n      baseline behavior\\n  depends_on:\\n  - D015\\n- id: D022\\n  date: 2026-05-14 05:58 UTC\\n  summary: 'D024: Bootstrap B=1000→10000 修正 + Results 写作 CRITICAL 修复'\\n  rationale: Reviewer 发现论文声称 B=10,000 但实际 profiling config 为 n_bootstrap=1000，导致 p\\n    < 10^-4 claim 不成立（B=1000 最多 p < 0.001）。修正方案：(1) fp16 参考文本改为 B=1000 + p < 0.001；(2)\\n    bf16 重跑全部设 n_bootstrap=10000 以支持更强统计声明。同时修复 results.tex dtype 虚假声明、\\\\label 冲突、random\\n    \\\"negligible\\\" 违反 D023 等问题。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: config_update\\n    result: n_bootstrap→10000\\n  - exp_id: bf16_importance_s020\\n    role: config_update\\n    result: n_bootstrap→10000\\n  - exp_id: bf16_importance_s025\\n    role: config_update\\n    result: n_bootstrap→10000\\n  - exp_id: v6_importance_s020\\n    role: evidence\\n    result: actual B=1000 confirmed\\n  depends_on:\\n  - D020\\n  - D023\\n- id: D023\\n  date: 2026-05-14 06:00 UTC\\n  summary: Bootstrap B 值修正：fp16 实际 B=1000（非论文误写 10000），bf16 重跑设 n_bootstrap=10000\\n  rationale: Reviewer 审查发现 results_5_1.tex 声称 B=10000 但 profiling config 实际为 n_bootstrap=1000。直接后果：(1)\\n    p < 10^-4 声明不成立，B=1000 精度上限为 p < 0.001；(2) CI 宽度有差异。修正策略：fp16 参考数据如实标注 B=1000；bf16\\n    重跑批次将 n_bootstrap 设为 10000，最终论文基于 bf16 数据可合法声称 B=10000。同时修正 paper_framing.md RC4\\n    部分。\\n  related_experiments:\\n  - exp_id: v6_importance_s020\\n    role: evidence\\n    result: profiling config confirmed n_bootstrap=1000\\n  - exp_id: v6_importance_s030\\n    role: evidence\\n    result: profiling config confirmed n_bootstrap=1000\\n  - exp_id: bf16_importance_s015\\n    role: affected\\n    result: will use n_bootstrap=10000\\n  - exp_id: bf16_importance_s020\\n    role: affected\\n    result: will use n_bootstrap=10000\\n  - exp_id: bf16_importance_s025\\n    role: affected\\n    result: will use n_bootstrap=10000\\n  depends_on:\\n  - D020\\n  - D019\\n- id: D024\\n  date: 2026-05-14 06:01 UTC\\n  summary: Bootstrap B 值修正：fp16 实际 B=1000（论文误写 10000），bf16 重跑设 n_bootstrap=10000；统一\\n    results 文件消除 dtype 矛盾和 label 冲突\\n  rationale: 4 份 Reviewer 报告一致标记 CRITICAL：(1) profiling_results.json 确认 n_bootstrap=1000，论文声称\\n    B=10000 属数据报告错误，p < 10^-4 不成立（B=1000 上限 p < 0.001）；(2) results.tex 声称 bf16 但数据全为\\n    fp16；(3) 两文件 \\\\label 冲突。修正策略：bf16 重跑时设 n_bootstrap=10000 一劳永逸，final paper 用 bf16\\n    数据可合法声称 B=10000。results_5_1.tex 作为 fp16 参考存档，results.tex 为 canonical skeleton，统一\\n    label。\\n  related_experiments:\\n  - exp_id: v6_importance_s020\\n    role: evidence\\n    result: profiling config confirms n_bootstrap=1000\\n  - exp_id: v6_importance_s030\\n    role: evidence\\n    result: profiling config confirms n_bootstrap=1000\\n  - exp_id: bf16_importance_s015\\n    role: fix_target\\n    result: set n_bootstrap=10000\\n  - exp_id: bf16_importance_s020\\n    role: fix_target\\n    result: set n_bootstrap=10000\\n  - exp_id: bf16_importance_s025\\n    role: fix_target\\n    result: set n_bootstrap=10000\\n  depends_on:\\n  - D020\\n  - D019\\n- id: D025\\n  date: 2026-05-14 06:27 UTC\\n  summary: Claim 锚点从 sign reversal 转为 magnitude gradient——s=0.15 sign reversal 由 outlier\\n    驱动，不作为主证据\\n  rationale: Reviewer 审查 bf16_importance_s015 发现：high_sparsity mean=-0.150 但 median=+0.006，skewness=-14.99，仅\\n    2 个 outlier 拉负。winsorized mean 保留负号但幅度大幅缩小(-0.062)。\\\"magnitude gradient\\\"(low >\\n    mid > high)在 mean/median/winsorized mean 上均稳健，是更可靠的 claim 锚点。s=0.25 gradient=85.4x\\n    更强且无 sign reversal 争议。论文应以 magnitude gradient 为主证据，sign reversal 作为 mean-level\\n    次级观察并加 caveat。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: evidence\\n    result: sign reversal fragile at mean level; magnitude gradient robust\\n  depends_on: []\\n- id: D026\\n  date: 2026-05-14 06:27 UTC\\n  summary: 论文核心证据改用 CI non-overlap + 绝对 II 值，gradient ratio 降级为辅助描述\\n  rationale: 'Reviewer 审查发现：(1) gradient_paired_aggregate 因 high_sparsity II 近零（s015:\\n    0.00012, s025: 0.01）导致比值膨胀无统计意义；(2) 同一实验不同 gradient 计算方法得 16x vs 69x（s015）或 85x\\n    vs 222x（s025），审稿人必攻此不一致。决定：论文主体用三 phase 的 II 绝对值 + bootstrap CI 作为核心证据（CI non-overlap\\n    已通过验证），gradient ratio 仅作辅助描述性语言，不作为 headline number。等 s020 bf16 完成后做三点 dose-response\\n    分析替代单一 gradient 数字。同时 paper_framing.md 中 \\\"11-42×\\\" 数字需在 bf16 全部完成后统一更新为基于 CI 的表述。'\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: evidence\\n    result: gradient_paired_aggregate=69.24 vs gradient_low_over_abs_high=16.02, 4.3x差异\\n  - exp_id: bf16_importance_s025\\n    role: evidence\\n    result: gradient_paired_aggregate=222.35 vs gradient_low_over_high=85.4, 2.6x差异\\n  depends_on:\\n  - D015\\n  - D023\\n- id: D027\\n  date: 2026-05-14 06:41 UTC\\n  summary: 论文 high-phase II 统一用 median 报告，辅以 winsorized mean，注明 skewness\\n  rationale: bf16_importance_s020 的 high-phase skewness=16.67，2 个 outlier 把 raw mean\\n    从负拉到 +0.129（winsorized_mean=-0.030, median=0.015）。三个 sparsity level 的 high-phase\\n    均存在右偏。用 raw mean 报告会被审稿人攻击为 outlier-driven。统一用 median 反映 central tendency，winsorized\\n    mean 作为 robustness check，skewness 作为分布特征注明。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: evidence\\n    result: high-phase 同样右偏\\n  - exp_id: bf16_importance_s020\\n    role: trigger\\n    result: skewness=16.67, mean=+0.129 vs winsorized=-0.030\\n  - exp_id: bf16_importance_s025\\n    role: evidence\\n    result: high-phase 跨 sparsity 一致\\n  depends_on: []\\n- id: D028\\n  date: 2026-05-14 06:42 UTC\\n  summary: bf16 importance 全系列 4/4 完成，gradient ratio 47-104×，远超 fp16 的 11-42×；s=0.30\\n    高 phase CI>0 可作论文叙事亮点\\n  rationale: bf16 DeepSeek importance s015-s030 全部 PASS，phase gradient 方向跨 4 个 sparsity\\n    level 高度一致。低/高 phase ratio 从 47×(s020) 到 104×(s030) 单调递增，比 fp16 系列的 11-42× 显著更强——bf16\\n    消除了数值精度噪声后效应更清晰。s=0.30 是唯一高 phase CI 完全>0 的水平，说明 compound effect 在高 sparsity 下渗透到所有\\n    phase，可用于论文叙事。ROADMAP 数字待 bf16 random 对照组完成后统一更新。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: evidence\\n    result: PASS, low/high=69× (median)\\n  - exp_id: bf16_importance_s020\\n    role: evidence\\n    result: PASS, low/high=47×\\n  - exp_id: bf16_importance_s025\\n    role: evidence\\n    result: PASS, low/high=85×\\n  - exp_id: bf16_importance_s030\\n    role: evidence\\n    result: PASS, low/high=104×, high CI>0\\n  depends_on:\\n  - D027\\n- id: D029\\n  date: 2026-05-14 06:43 UTC\\n  summary: v6_random_s030 PASS 是 outlier artifact，permutation test mean→median 修复升为\\n    bf16 random 前置阻塞项\\n  rationale: Reviewer 审查确认：s030 random 的 Verdict=PASS 由单个 mid-phase extreme segment\\n    驱动（attn PPL=382.65，II mean=-230.76）。Median/winsorized mean 下三 phase 平坦（2.4-4.7），与\\n    s015/s020/s025 一致。Mean-based permutation test 在高 sparsity 完全不可靠。必须在 bf16 random\\n    batch 产出数据前修复 test statistic 为 median-based，否则 bf16 会复现假阳性。论文报告 random baseline\\n    统一用 median + winsorized mean。\\n  related_experiments:\\n  - exp_id: v6_random_s030_r3\\n    role: trigger\\n    result: PASS is outlier artifact\\n  - exp_id: v6_random_s015\\n    role: reference\\n    result: FAIL (expected)\\n  - exp_id: v6_random_s020\\n    role: reference\\n    result: FAIL (expected)\\n  - exp_id: v6_random_s025\\n    role: reference\\n    result: FAIL (expected)\\n  depends_on:\\n  - D027\\n- id: D030\\n  date: 2026-05-14 06:46 UTC\\n  summary: Random baseline mean-based II outlier 确认为系统性问题，论文须说明 II heavy-tail 特性及\\n    median 选择理由\\n  rationale: bf16_ds_rand_s015 复现了 v6_random_s030_r3 的完全一致模式：mid-phase 个别 segment\\n    random 移除命中关键 attention head → attn PPL 爆炸 → II mean 被 1-2 个 outlier 主导（mean=-172.66\\n    vs median=0.097）。两个独立实验（不同 sparsity、不同精度）出现同样问题，确认系统性。预计 bf16_ds_rand_s020/s025\\n    也会出现。论文 methodology 必须明确说明 II 的 heavy-tail 特性 + 为什么使用 median（审稿人看到 mean/median\\n    差异 1000× 必问）。Median 数据本身质量正常，fp16/bf16 量级一致。\\n  related_experiments:\\n  - exp_id: bf16_ds_rand_s015\\n    role: trigger\\n    result: mean outlier confirmed systemic\\n  - exp_id: v6_random_s030_r3\\n    role: reference\\n    result: first instance of same pattern\\n  depends_on:\\n  - D029\\n- id: D031\\n  date: 2026-05-14 06:52 UTC\\n  summary: bf16 DeepSeek importance 全系列 4/4 PASS，论文 gradient 报告统一用差值 (II_low - II_high)\\n    替代 ratio\\n  rationale: bf16 importance s015/s020/s025/s030 全部 verdict=PASS，phase gradient (low>>mid>>high)\\n    在所有 sparsity level 稳定成立，跨 sparsity 单调递增，low vs mid CI 不重叠。Median-based ratio gradient（66-276×）因\\n    high_median 极小（0.006-0.053）而不稳定，审稿人会质疑近零除法。决定论文和 ROADMAP 统一用差值 (median_low - median_high)\\n    报告 gradient，避免 ratio metric 的分母近零问题。差值：s015=0.39, s020=1.49, s025=7.17, s030=14.59——清晰的单调递增趋势，不受除零影响。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: evidence\\n    result: PASS, low_median=0.40\\n  - exp_id: bf16_importance_s020\\n    role: evidence\\n    result: PASS, low_median=1.50\\n  - exp_id: bf16_importance_s025\\n    role: evidence\\n    result: PASS, low_median=7.20\\n  - exp_id: bf16_importance_s030\\n    role: evidence\\n    result: PASS, low_median=14.64\\n  depends_on:\\n  - D029\\n  - D030\\n- id: D032\\n  date: 2026-05-14 07:28 UTC\\n  summary: 论文主统计检验改用 difference statistic（ii_low − ii_high），ratio 降为 appendix 辅助\\n  rationale: Permutation test 全 4 水平结果：difference statistic 全部 Bonferroni 校正后 p<0.005，效应量单调递增（0.35→1.14→4.02→9.95）。Ratio\\n    statistic 受 EPS=0.01 过滤影响，低 sparsity 水平 n_paired 从 49 降至 32-41，s015/s020/s025\\n    不显著。Difference 对重尾分布更 robust，不受 EPS 过滤影响，且展示出清晰的 sparsity-severity 单调递增关系——解决了\\n    C2 之前的非单调性问题。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: importance_baseline\\n    result: PASS\\n  - exp_id: bf16_importance_s020\\n    role: importance_baseline\\n    result: PASS\\n  - exp_id: bf16_importance_s025\\n    role: importance_baseline\\n    result: PASS\\n  - exp_id: bf16_importance_s030\\n    role: importance_baseline\\n    result: PASS\\n  - exp_id: bf16_ds_rand_s015\\n    role: random_control\\n    result: verdict_pending\\n  - exp_id: bf16_ds_rand_s020\\n    role: random_control\\n    result: verdict_pending\\n  - exp_id: bf16_ds_rand_s025\\n    role: random_control\\n    result: verdict_pending\\n  - exp_id: bf16_ds_rand_s030\\n    role: random_control\\n    result: verdict_pending\\n  depends_on:\\n  - D028\\n  - D030\\n- id: D033\\n  date: 2026-05-14 07:45 UTC\\n  summary: 弃用所有 ratio 指标，论文主指标改为 median difference + Cohen's d；registry gradient_paired_aggregate\\n    字段定义不一致已确认\\n  rationale: 溯源调查发现 registry 中 gradient_paired_aggregate 字段计算方式跨 sparsity 不一致（s015/s025\\n    用 median ratio，s020/s030 用 mean difference），导致 \\\"47-104×\\\" 不可溯源。根因：ratio 在 high-phase\\n    II 接近 0 时不稳定（29-49% 样本 < EPS=0.01）。替代方案 median difference 单调递增（0.39→1.48→7.16→14.59），Cohen's\\n    d 同样单调（0.60→0.72→0.95→1.12），与 D032 permutation test difference statistic 一致。论文全面弃用\\n    ratio 类指标。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: source_data\\n    result: gradient_paired_aggregate=69.24 (median ratio)\\n  - exp_id: bf16_importance_s020\\n    role: source_data\\n    result: gradient_paired_aggregate=5.90 (mean difference, mislabeled)\\n  - exp_id: bf16_importance_s025\\n    role: source_data\\n    result: gradient_paired_aggregate=222.35 (median ratio, inflated by small denominator)\\n  - exp_id: bf16_importance_s030\\n    role: source_data\\n    result: gradient_paired_aggregate=57.24 (mean difference, mislabeled)\\n  depends_on:\\n  - D032\\n  - D028\\n- id: D034\\n  date: 2026-05-14 07:55 UTC\\n  summary: 'C5 cross-model replication confirmed: Qwen2.5-7B-Instruct bf16 importance\\n    4/4 PASS，median difference 单调递增 0.039→2.943'\\n  rationale: Qwen bf16 importance 全 4 水平 PASS，median difference 单调递增（0.039→0.235→1.268→2.943），与\\n    DeepSeek 模式一致（0.39→14.59），magnitude 约为 DeepSeek 1/5。CI non-overlap 在所有 4 个 sparsity\\n    level 成立。跨模型方向一致性强，C5 claim 可以成立。\\n  related_experiments:\\n  - exp_id: bf16_qw_imp_s015\\n    role: cross_model_replication\\n    result: PASS, diff=0.039\\n  - exp_id: bf16_qw_imp_s020\\n    role: cross_model_replication\\n    result: PASS, diff=0.235\\n  - exp_id: bf16_qw_imp_s025\\n    role: cross_model_replication\\n    result: PASS, diff=1.268\\n  - exp_id: bf16_qw_imp_s030\\n    role: cross_model_replication\\n    result: PASS, diff=2.943\\n  depends_on:\\n  - D032\\n  - D033\\n- id: D035\\n  date: 2026-05-14 08:01 UTC\\n  summary: Cohen's d 修正：实际值 0.44→0.80（旧 claim 0.60→1.12 偏高 25-30%），单调递增趋势不变，叙事改为\\\"small→large\\n    effect size gradient\\\"\\n  rationale: Agent 用 paired Cohen's d (n=49, B=10000 bootstrap CI) 重新计算，发现 D033 中的数字无实际计算来源。实际\\n    s015=0.44(small), s020=0.52(medium), s025=0.68(medium), s030=0.80(large)。趋势正确但绝对值需修正。论文必须引用实际计算值。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: source\\n    result: d=0.44\\n  - exp_id: bf16_importance_s020\\n    role: source\\n    result: d=0.52\\n  - exp_id: bf16_importance_s025\\n    role: source\\n    result: d=0.68\\n  - exp_id: bf16_importance_s030\\n    role: source\\n    result: d=0.80\\n  depends_on:\\n  - D033\\n- id: D036\\n  date: 2026-05-14 08:02 UTC\\n  summary: Cohen's d 修正：实际 0.44→0.52→0.68→0.80（D033 声称 0.60→1.12 高估 35-45%），单调递增趋势不变，论文引用新值\\n  rationale: Agent 用 paired Cohen's d_z + bootstrap CI(B=10000) 重新计算，Reviewer 审查 PASS。D033\\n    原值无计算来源。新值全部 CI 下界>0（显著），small→large 效应量递增与 sparsity-severity 叙事一致。论文需引用 cohens_d_bf16.json\\n    中的实际数值。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: source\\n    result: d=0.44 [0.35,0.78]\\n  - exp_id: bf16_importance_s020\\n    role: source\\n    result: d=0.52 [0.43,0.90]\\n  - exp_id: bf16_importance_s025\\n    role: source\\n    result: d=0.68 [0.56,0.86]\\n  - exp_id: bf16_importance_s030\\n    role: source\\n    result: d=0.80 [0.67,1.02]\\n  depends_on:\\n  - D033\\n- id: D037\\n  date: 2026-05-14 08:05 UTC\\n  summary: 'Qwen Cohen''s d: 0.28→1.02 单调递增，但 s015 CI 含 0 不显著。叙事调整为 threshold 差异化——Qwen\\n    s≥0.20, DeepSeek s≥0.15'\\n  rationale: Reviewer 审查确认 Qwen s015 d=0.28 CI=[-0.006, 0.60] 在 95% 水平不显著。s020-s030\\n    全部显著且单调递增(0.55→0.89→1.02)。Qwen 高端效应量反超 DeepSeek(0.89/1.02 vs 0.68/0.80)因方差更低。叙事改为\\n    threshold 差异化表述，比统一 claim 更精确更 robust。n_skipped=4(8%) 需论文注明。\\n  related_experiments:\\n  - exp_id: bf16_qw_imp_s015\\n    role: source\\n    result: d=0.28 CI含0 不显著\\n  - exp_id: bf16_qw_imp_s020\\n    role: source\\n    result: d=0.55 显著\\n  - exp_id: bf16_qw_imp_s025\\n    role: source\\n    result: d=0.89 显著\\n  - exp_id: bf16_qw_imp_s030\\n    role: source\\n    result: d=1.02 显著\\n  depends_on:\\n  - D035\\n  - D034\\n- id: D038\\n  date: 2026-05-14 08:06 UTC\\n  summary: 'Qwen Cohen''s d: 0.28→1.02，s015 不显著(CI含0)。论文 dose-response claim 改为 \\\"s≥0.20\\n    for Qwen, s≥0.15 for DeepSeek\\\"，s015 行加注'\\n  rationale: Qwen s015 d=0.28 CI=[-0.006,0.60] 不显著；s020-s030 全显著且效应量反超 DeepSeek(s025:0.89vs0.68,\\n    s030:1.02vs0.80)。处理策略：(1) cross-model 表 s015 行注明 Qwen 不显著；(2) 叙事用 model-specific\\n    threshold 角度：compound interaction onset threshold 因模型而异，DeepSeek s≥0.15 即可观测，Qwen\\n    需 s≥0.20；(3) 这反而支持一个更细致的 claim——threshold 差异可能与模型的 attention head redundancy 有关。n_skipped=4(8%)\\n    需注明有效样本量。\\n  related_experiments:\\n  - exp_id: bf16_qw_imp_s015\\n    role: source\\n    result: d=0.28 non-significant\\n  - exp_id: bf16_qw_imp_s020\\n    role: source\\n    result: d=0.55\\n  - exp_id: bf16_qw_imp_s025\\n    role: source\\n    result: d=0.89\\n  - exp_id: bf16_qw_imp_s030\\n    role: source\\n    result: d=1.02\\n  depends_on:\\n  - D035\\n  - D034\\n- id: D039\\n  date: 2026-05-14 08:32 UTC\\n  summary: n_bootstrap=1000 处理策略：优先尝试从原始数据 re-bootstrap B=10000，否则论文如实标注 B=1,000\\n  rationale: 'D023 决定 bf16 实验用 B=10000，但实际所有 bf16 profiling 均为 B=1000。Cohen''s d 已用\\n    B=10000 不受影响。PASS/FAIL 判定在 B=1000 下有效。最优方案：检查 profiling_results.json 是否保存了 raw\\n    per-sample II 值，若有则用脚本 re-bootstrap B=10000（分钟级完成，不需重跑实验）；若无原始数据则论文如实标注 profiling\\n    CI: B=1,000 (p<0.001), Cohen''s d CI: B=10,000。'\\n  related_experiments:\\n  - exp_id: bf16_ds_imp_s015\\n    role: affected\\n    result: B=1000\\n  - exp_id: bf16_ds_imp_s030\\n    role: affected\\n    result: B=1000\\n  - exp_id: bf16_qw_imp_s015\\n    role: affected\\n    result: B=1000\\n  - exp_id: bf16_qw_imp_s020\\n    role: affected\\n    result: B=1000\\n  depends_on:\\n  - D023\\n  - D024\\n- id: D040\\n  date: 2026-05-14 08:32 UTC\\n  summary: Qwen random gradient 论文表述修正：不可声称 \\\"no phase gradient\\\"，应表述为统计不显著\\n  rationale: Qwen random 三组实验 gradient 均非零（0.050/0.129/0.660），s015 甚至 random > importance（0.050\\n    vs 0.039）。与 DeepSeek random 的清晰分离（13-39×）不同，Qwen 分离度仅 0.8-1.9×。CI overlap test\\n    正确判定 FAIL，结论有效。但论文 §5 需讨论：(1) 低 sparsity 下两种方法的 phase 效应均弱且不可区分；(2) 正确表述为 \\\"random\\n    gradient 不具统计显著性\\\" 而非 \\\"random 无 gradient\\\"。\\n  related_experiments:\\n  - exp_id: bf16_qw_rand_s015\\n    role: evidence\\n    result: FAIL, gradient=0.050\\n  - exp_id: bf16_qw_rand_s020\\n    role: evidence\\n    result: FAIL, gradient=0.129\\n  - exp_id: bf16_qw_rand_s025\\n    role: evidence\\n    result: FAIL, gradient=0.660\\n  - exp_id: bf16_qw_imp_s015\\n    role: comparison\\n    result: gradient=0.039, Cohen's d=0.28\\n  depends_on:\\n  - D037\\n  - D038\\n- id: D041\\n  date: 2026-05-14 08:45 UTC\\n  summary: 'CRITICAL: Qwen random s030 PASS (gradient 4.241 > importance 2.943)——borderline，立即\\n    B=10000 re-bootstrap 验证'\\n  rationale: bf16_qw_rand_s030 CI overlap test PASS，random gradient (4.241) > importance\\n    gradient (2.943)。但 CI gap 仅 0.161（极 borderline），且 n_bootstrap=1000（D023 要求 10000）。B=10000\\n    的更窄 CI 可能翻转为 FAIL。DeepSeek random s030 gradient=1.538 仍 FAIL（importance/random\\n    分离>10×），问题仅限 Qwen s030。两种应对路径：(1) B=10000 re-bootstrap 后 FAIL → 维持原叙事，注明 B=1000\\n    时 borderline；(2) B=10000 后仍 PASS → 论文叙事调整为\\\"moderate sparsity 下 importance 特有，extreme\\n    sparsity 下两策略收敛\\\"，与 entropy-discrimination collapse 机制一致（极高 sparsity 下 head pruning\\n    损伤压倒策略差异）。\\n  related_experiments:\\n  - exp_id: bf16_qw_rand_s030\\n    role: trigger\\n    result: PASS, gradient=4.241\\n  - exp_id: bf16_qw_imp_s030\\n    role: comparison\\n    result: PASS, gradient=2.943\\n  - exp_id: bf16_ds_rand_s030\\n    role: cross-model\\n    result: FAIL, gradient=1.538\\n  depends_on:\\n  - D034\\n  - D039\\n  - D040\\n- id: D042\\n  date: 2026-05-14 08:53 UTC\\n  summary: D041 更新：Qwen random s030 B=10000 后 Cohen's d≈0，aggregate PASS 但无 within-problem\\n    consistency，critical 降级 warning\\n  rationale: B=10000 re-bootstrap 后：(1) median_diff 从 4.241 降至 2.418，现在小于 importance\\n    的 2.943；(2) Cohen's d = -0.035（importance 为 1.02），说明 random 的 aggregate gradient\\n    来自 between-problem variability 而非 within-problem phase effect；(3) permutation\\n    p=0.012，Bonferroni 校正后 borderline（阈值 0.0125）。论文叙事策略：主用 Cohen's d 作为 importance\\n    vs random 的判别指标（1.02 vs ~0，无争议），承认 Qwen s030 aggregate median 有弱趋势但无 within-problem\\n    consistency，与 entropy-discrimination collapse 机制一致——extreme sparsity 下 between-problem\\n    variability 增大但不形成系统性 phase effect。\\n  related_experiments:\\n  - exp_id: bf16_qw_rand_s030\\n    role: trigger\\n    result: PASS verdict retained, but Cohen's d=-0.035, median_diff=2.418\\n  - exp_id: bf16_qw_imp_s030\\n    role: comparison\\n    result: Cohen's d=1.02, gradient=2.943\\n  depends_on:\\n  - D041\\n  - D040\\n  - D038\\n- id: D043\\n  date: 2026-05-14 08:59 UTC\\n  summary: D041 结论：B=10000 re-bootstrap 后 bf16_qw_rand_s030 仍 PASS (gradient 2.418)，但\\n    Cohen's d≈0——效应量可忽略，叙事可防御\\n  rationale: B=10000 re-bootstrap 将 gradient 从 4.241 降至 2.418（CI 收窄），verdict 仍 PASS。但\\n    Cohen's d ≈ 0 表明无实际意义的效应量。对比 Qwen importance s030 Cohen's d=1.02，两者差异巨大。论文叙事策略：(1)\\n    Table 中标注 QW random s030 为 \\\"borderline PASS, d≈0\\\"；(2) §5 讨论：CI test 敏感到 borderline\\n    显著但效应量可忽略；(3) 与 importance 的 dose-response gradient（d=0.28→1.02）形成对比——random 即使\\n    borderline PASS 也无 dose-response 模式。DeepSeek random 全 4 水平均 FAIL，问题仅限 Qwen s030\\n    单个数据点。\\n  related_experiments:\\n  - exp_id: bf16_qw_rand_s030\\n    role: trigger\\n    result: PASS, gradient=2.418, Cohen's d≈0\\n  - exp_id: bf16_qw_imp_s030\\n    role: comparison\\n    result: PASS, gradient=2.943, Cohen's d=1.02\\n  depends_on:\\n  - D041\\n- id: D044\\n  date: 2026-05-14 09:10 UTC\\n  summary: 'C4 entropy-discrimination collapse: Qwen s025 符号反转需调查，论文需 cross-model\\n    caveat。Gini 效应 model-dependent（Qwen 1/3~1/4 of DeepSeek）。C4 维持 partially_confirmed\\n    直到 per-problem 分析完成。'\\n  rationale: Reviewer 审查 qwen_c4_entropy 结果发现：(1) Entropy Δ 6/8 configurations 方向一致但\\n    Qwen s025 有符号反转 (+0.0451 vs DeepSeek -0.0446)；(2) Gini 效应 Qwen 远弱于 DeepSeek。不杀\\n    C4 但需要 honest reporting + per-problem 分析确认是否 outlier-driven。\\n  related_experiments:\\n  - exp_id: qwen_c4_entropy\\n    role: evidence\\n    result: anomaly at s025\\n  - exp_id: c4_attention_entropy\\n    role: baseline\\n    result: DeepSeek all negative\\n  depends_on:\\n  - D032\\n  - D034\\n- id: D045\\n  date: 2026-05-14 09:17 UTC\\n  summary: C4 从 Core Claim 降为 §6 supporting analysis（方案 A）；采用 per-problem paired Cohen's\\n    d 作为论文主统计量\\n  rationale: qwen_c4_entropy 30/30 完成后结论 negative：entropy-discrimination collapse\\n    在 DeepSeek 成立但 Qwen 不复现（s025 符号反转）。论文核心 story 是 phenomenon（phase-dependent severity\\n    gradient，C1-C3/C5/C6 全 confirmed），不依赖 mechanism claim。降级 C4 最 defensible，避免 overclaim\\n    被审稿人攻击。Cohen's d 采用 per-problem paired 因为实验是 within-subjects 配对设计，segment-level\\n    aggregate 放 supplementary 作 robustness check。\\n  related_experiments:\\n  - exp_id: qwen_c4_entropy\\n    role: trigger\\n    result: negative — Qwen entropy proxy 不复现 DeepSeek 的 discrimination collapse\\n  - exp_id: c4_attention_entropy\\n    role: reference\\n    result: DeepSeek entropy collapse confirmed\\n  - exp_id: bf16_importance_s015\\n    role: reference\\n    result: B=10000 re-bootstrap completed\\n  - exp_id: bf16_importance_s030\\n    role: reference\\n    result: B=10000 re-bootstrap completed\\n  depends_on:\\n  - D044\\n  - D039\\n- id: D046\\n  date: 2026-05-14 09:19 UTC\\n  summary: 'C4 entropy-collapse 从 Core Claim 降为 §6 supporting analysis（方案 A: model-dependent\\n    mechanism）'\\n  rationale: Qwen s025 entropy delta 反转(+0.045)、s030 近零，跨模型一致性不成立。但 DeepSeek 四水平一致，且\\n    Qwen mid-phase 仅 26 segments 统计功效不足可能是 confound。选方案 A：保留 §6 分析但诚实报告两模型差异，不再作为跨模型通用\\n    mechanism claim。核心 empirical claims C1-C3/C5/C6 不受影响。若 s025 调查确认是方差 artifact 可回升强度。\\n  related_experiments:\\n  - exp_id: qwen_c4_entropy\\n    role: primary\\n    result: 'C4 cross-model inconsistent: DeepSeek consistent, Qwen partial (s015/s020\\n      ok, s025 reversed, s030 near-zero)'\\n  - exp_id: worker_analysis_qwen_s025_entropy_investigation\\n    role: followup\\n    result: completed, pending Agent processing\\n  depends_on: []\\n- id: D047\\n  date: 2026-05-14 09:38 UTC\\n  summary: 纳入 6-point dose-response 数据（s=0.10~0.35），限定 II_high<0.06 claim 至 s≤0.30\\n  rationale: 6-point 单调性 Spearman ρ=1.0 显著加固 C2+C5。Qwen s=0.10 sub-additive 现象揭示 onset\\n    threshold，增加科学深度。DS s=0.35 II_high=0.105 打破原 \\\"<0.06\\\" claim，需限定范围。收益（更强证据链）远大于成本（限定一个\\n    claim + 加一段 onset 讨论）。\\n  related_experiments:\\n  - exp_id: bf16_ds_imp_s010\\n    role: extension\\n    result: near-zero II, monotonicity anchor\\n  - exp_id: bf16_ds_imp_s035\\n    role: extension\\n    result: II_high=0.105, ceiling effect\\n  - exp_id: bf16_qw_imp_s010\\n    role: extension\\n    result: sub-additive II, onset threshold\\n  - exp_id: bf16_qw_imp_s035\\n    role: extension\\n    result: monotonicity confirmed\\n  depends_on: []\\n- id: D048\\n  date: 2026-05-14 09:41 UTC\\n  summary: 统一使用 paired d_z (cohens_d_bf16.json) 替换论文全文 independent-samples d\\n  rationale: Reviewer CRITICAL：配对数据（同一 problem 的 low/high phase）必须用 paired d_z = mean(diffs)/std(diffs)，论文错误使用了\\n    rebootstrap 的 independent-samples d，效应量系统性膨胀 20-40%。Table 4 caption 描述与实际计算不匹配。采用方案\\n    A：直接用 cohens_d_bf16.json 已有的 paired d_z 值，修改论文 6 处。主要结论不变。\\n  related_experiments: []\\n  depends_on: []\\n- id: D049\\n  date: 2026-05-14 09:55 UTC\\n  summary: Table 4 bootstrap CI caption 澄清：改 caption 措辞而非重算 CI\\n  rationale: Reviewer 发现 Table 4 bootstrap CI 使用 independent resampling 但 caption\\n    写 \\\"per-problem paired\\\"。unpaired bootstrap 产生更宽（更保守）的 CI，所有结论方向不变。选择方案 (b)：caption\\n    明确 CI 为 independent bootstrap of medians，避免重新计算的成本。优先级低于编译冲刺，编译通过后处理。\\n  related_experiments: []\\n  depends_on:\\n  - D048\\n- id: D050\\n  date: 2026-05-14 10:03 UTC\\n  summary: 回退 fix-cohens-d-notation Worker 的全部修改，恢复 D048 正确的 paired d_z 值\\n  rationale: Worker 被文件名 cohens_d_paired_b10000.json 中的 \\\"paired\\\" 误导，实际该文件使用 pooled-SD\\n    independent-samples d 公式。正确数据源是 cohens_d_bf16.json（compute_cohens_d.py 使用 mean(diffs)/std(diffs,ddof=1)\\n    = paired d_z）。符号统一用 \\\"Cohen's d\\\" 而非 d_z。\\n  related_experiments: []\\n  depends_on:\\n  - D048\\n- id: D051\\n  date: 2026-05-14 10:04 UTC\\n  summary: 图表全部基于过时数据，需用 bf16 canonical 数据重新生成；删除硬编码脚本 generate_all_figures.py\\n  rationale: Reviewer 发现：(1) generate_all_figures.py 硬编码数据与任何分析文件不匹配（G_imp 差数量级），Cohen's\\n    d 使用弃用的 independent-samples d；(2) generate_paper_figures.py 读取 v5 旧数据（bootstrap_results_full.json\\n    / v6_analysis_results.json），不是 bf16 canonical 数据；(3) figures/ 和 paper_figures/\\n    两个目录文件不一致。修复：删除硬编码脚本，用 bf16 profiling_output_bf16_* 数据重新生成所有分析 JSON 和图表，统一输出到\\n    paper_figures/。\\n  related_experiments: []\\n  depends_on:\\n  - D048\\n  - D050\\n- id: D052\\n  date: 2026-05-14 13:30 UTC\\n  summary: 采纳 Reviewer 审查：C5 pilot-first + heuristic baseline，C2 预注册 s015 ns 叙事，C9\\n    仅加引用\\n  rationale: Reviewer 独立审查 Round 1 应对方案后建议：(1) C5 先用 1-2 个 sparsity level 做 2h pilot，oracle\\n    回收 >30% compound degradation 才全面铺开，否则降为 future work；(2) C5 必须加 simple heuristic\\n    baseline（token position ratio 或 cumulative attention entropy 作 phase proxy），与\\n    oracle 构成上下界；(3) compute-matched 硬约束；(4) C2 n=500 前预定义\\\"若 s015 仍 ns 则叙事改为 compound\\n    effect emerges above threshold\\\"；(5) C9 Lethe 仅 Related Work 加一句区分引用，另加 SparK；(6)\\n    S3/S7 考虑升级为 C 级；(7) 预留 1 天写 rebuttal letter。\\n  related_experiments: []\\n  depends_on: []\\n- id: D053\\n  date: 2026-05-14 14:59 UTC\\n  summary: c5b_pilot s_trans cap 澄清：cap 作用于 s_trans 本身（≤0.50），不是 δ'\\n  rationale: Reviewer warning 发现 §3.2 公式（δ' cap=0.50）与 handoff checklist（s_trans capped\\n    at 0.50）存在歧义。选择解读 B（s_trans ≤ 0.50）：pilot 目的是检测 phase-aware KV modulation 信号存在性，s_trans=0.50\\n    已是 substantial modulation；80% KV eviction（解读 A 在 s=0.30 时）可能导致 forward pass 退化，污染后续\\n    phase 的 II 计算，引入混淆变量。信号存在后可在 follow-up 中升级探测范围。\\n  related_experiments:\\n  - exp_id: c5b_pilot\\n    role: target\\n    result: pending\\n  depends_on:\\n  - D052\\n- id: D054\\n  date: 2026-05-14 18:11 UTC\\n  summary: II 主指标从 mean 切换为 median + median bootstrap CI\\n  rationale: n=500 实验揭示 mean 被极端 outlier 摧毁（rand s015 mean 从 -1.9 暴跌到 -185K，而 median\\n    稳定 0.103→0.118）。imp 和 rand 的 outlier 方向相反，mean 虚假放大了效应量。Median 稳定、CI 收窄符合预期，作为\\n    heavy-tailed 分布的 robust central tendency 指标。\\n  related_experiments:\\n  - exp_id: c2_n500_deepseek\\n    role: trigger\\n    result: rand s015 mean=-185K, median=0.118\\n  - exp_id: c1_mvp\\n    role: affected\\n    result: mean 值需重新评估\\n  - exp_id: c3_llama\\n    role: affected\\n    result: mean 值需重新评估\\n  depends_on: []\\n- id: D055\\n  date: 2026-05-14 18:41 UTC\\n  summary: 'c5b_pilot conditional retry: CPU 诊断 root cause → 可修则 c2_n500 GPU 释放后 2h\\n    time-box 重试 → 仍失败或不可修则降为 future work'\\n  rationale: c5b 5×进程死亡是技术故障非假设否定。论文是 empirical finding paper，mitigation 非核心 claim，framing\\n    已有 future work fallback。距截稿 11 天，核心 claims 已 confirmed，诊断无 GPU 成本，若可修则 2h retry\\n    有正 EV（加强 RC3 应对）；若不可修则干净收尾。\\n  related_experiments:\\n  - exp_id: c5b_pilot\\n    role: subject\\n    result: failed 5×\\n  depends_on:\\n  - D052\\n- id: D056\\n  date: 2026-05-14 18:46 UTC\\n  summary: 撤回 D055，确认 c5b_pilot gate_failed（非技术故障）：oracle recovery 18% < 30% gate，C5b\\n    按 D052 预注册协议降为 future work\\n  rationale: D055 基于 Agent 汇报的\\\"5×进程死亡\\\"做出 conditional retry 决策，但 Reviewer 核实发现 PID\\n    154645 已正常完成 30/30 problems，结果文件存在(51KB)，gate_pass=false 是科学判定（oracle recovery\\n    18% < 30%）非技术故障。D052 预注册协议明确\\\"不达标→future work\\\"，D055 绕过了此协议。Heuristic recovery 32%\\n    > oracle 18% 的反直觉结果 + 两者 CI 均跨零，进一步确认当前 phase-aware allocation 信号不够强。论文 §6 Discussion\\n    可提及 pilot 结果（Wilcoxon 显著但效应量不足，方向正确需更精细方法）。\\n  related_experiments:\\n  - exp_id: c5b_pilot\\n    role: subject\\n    result: 'gate_failed: oracle recovery 18% < 30% threshold'\\n  depends_on:\\n  - D052\\n  - D055\\n- id: D057\\n  date: 2026-05-14 18:46 UTC\\n  summary: 修正 D055：c5b_pilot 实际已完成(gate_pass=false)，不需要 retry。Registry 改 gate_failed，c5b\\n    降为 future work grounding evidence\\n  rationale: Reviewer 发现 c5b_pilot PID 154645 于 02:37 UTC 正常完成 30/30 problems，非进程死亡。Oracle\\n    recovery 18% < 30% gate，heuristic 32% 但 CI 跨零（统计上不可区分零）。结论：naive phase-aware allocation\\n    信号存在（Wilcoxon p=0.002/0.024）但效应量不足，需更精细策略。作为 future work grounding evidence 写入论文\\n    §6 Discussion。\\n  related_experiments:\\n  - exp_id: c5b_pilot\\n    role: subject\\n    result: gate_failed (oracle 18% < 30% gate, heuristic 32% but CI crosses zero)\\n  depends_on:\\n  - D055\\n  - D052\\n- id: D058\\n  date: 2026-05-14 18:47 UTC\\n  summary: Qwen imp-vs-rand paired 对比 n=50 全部不显著：等 n=500 结果定论，预备 model-dependent magnitude\\n    叙事调整\\n  rationale: Reviewer 发现 Qwen 在 n=50 下 importance vs random 的 phase gradient paired\\n    对比全 4 水平不显著(p>0.07)，DeepSeek 全部高度显著(p≤0.0001)。n=50 对 Qwen 小效应量(d_z 0.09-0.16)功效不足，n=500\\n    是预设的功效提升实验。若 n=500 仍不显著，叙事调整为 \\\"effect magnitude is model-dependent, models with\\n    stronger importance discrimination show clearer phase-strategy differentiation\\\"——与\\n    discrimination collapse 机制一致(Qwen importance score 判别力本身较弱)。同时 Qwen mid-phase\\n    58% null rate 须在论文中披露 per-phase effective sample sizes。\\n  related_experiments:\\n  - exp_id: c2_qw_n500\\n    role: pending_verification\\n    result: running\\n  - exp_id: c2_n500_deepseek\\n    role: pending_verification\\n    result: running\\n  depends_on: []\\n- id: D059\\n  date: 2026-05-14 18:48 UTC\\n  summary: d_z 分场景报告：within-importance 保留 d_z，涉及 random 的比较只报 Wilcoxon p + median_diff，不报\\n    d_z（outlier 污染）\\n  rationale: Random pruning 14.2% catastrophic failure rate（ppl 爆炸至 236K，II min=-4.3M）导致\\n    mean-based d_z 不可靠。Within-importance 比较（C2 主结果）两边均为 importance 条件，无此问题，d_z 稳定。分场景处理既保持统计严谨性，又避免\\n    deadline 前大规模替换效应量指标。论文加脚注解释 random 不报 d_z 的原因（catastrophic ppl explosion in ~14%\\n    of random trials makes mean-based effect size unreliable）。\\n  related_experiments:\\n  - exp_id: c2_n500_deepseek\\n    role: context\\n    result: running — n=500 rand s015 outlier rate 14.2%\\n  depends_on:\\n  - D054\\n- id: D060\\n  date: 2026-05-14 18:52 UTC\\n  summary: C8 从 confirmed 降级为 partially_confirmed（qualitative direction consistent,\\n    quantitative interaction weaker）：LLaMA random 也显示 phase gradient，strategy-dependence\\n    弱于 DeepSeek/Qwen\\n  rationale: Reviewer 独立核实 c3_llama_results.json 发现：(1) within-importance phase gradient\\n    强且稳定（d_z~1.0）✓ (2) 但 imp_vs_rand 交互效应弱（d_z 0.19→0.34，仅 s030 Bonferroni 显著）(3)\\n    random eviction 在 LLaMA 上也显示非平凡 phase gradient（d_z 0.35→0.44, CI 排除零），与 DeepSeek/Qwen\\n    random 7/8 FAIL 模式定性不同。C8 支持 qualitative replication（importance phase gradient\\n    方向一致），但 strategy × phase interaction 的量化强度是 architecture-dependent。论文引用 LLaMA\\n    数据时必须加限定语，否则审稿人会攻击。\\n  related_experiments:\\n  - exp_id: c3_llama\\n    role: subject\\n    result: success but imp_vs_rand interaction weaker than DeepSeek/Qwen; random\\n      also shows phase gradient on LLaMA\\n  depends_on:\\n  - D056\\n- id: D061\\n  date: 2026-05-14 19:27 UTC\\n  summary: D058 已解决：n=500 下 DeepSeek 和 Qwen 的 paired gradient 均达 Bonferroni 显著\\n  rationale: s015 分析结果：DeepSeek median_D=-0.4227 p<0.0001 null_rate=10.2%；Qwen median_D=-0.0991\\n    p<0.0001 null_rate=45.2%。n=50 时 Qwen 功效不足的问题在 n=500 下完全解决。Qwen null rate 仍高(45.2%)，论文须披露\\n    per-phase effective sample size。\\n  related_experiments:\\n  - exp_id: c2_n500_deepseek\\n    role: primary\\n    result: significant\\n  - exp_id: c2_qw_n500\\n    role: primary\\n    result: significant\\n  depends_on:\\n  - D058\\n- id: D062\\n  date: 2026-05-14 19:37 UTC\\n  summary: Cron 监控改为 shell PID + sentinel 双机制，解决 profiling 实验 condition 切换时 PID 变化导致的反复误报\\n  rationale: c2_qw_n500 已第 3-4 次 cron 误报，每次触发 diagnose worker 浪费资源。根因：cron 监控 python\\n    PID 但 condition 切换时 PID 变化，且 slow path 只识别 tmux 不识别 screen。修复：(1) 改用 shell 脚本\\n    PID（全程不变）注册 cron (2) run script 末尾写 sentinel 供 fast path 检测 (3) PID 写入文件供排查。后续\\n    profiling 实验模板应默认包含 PID 文件 + sentinel 写入。\\n  related_experiments:\\n  - exp_id: c2_qw_n500\\n    role: trigger\\n    result: cron misfire fixed\\n  depends_on:\\n  - D061\\n\", \"total_chars\": 46741, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "3fcdc131-c46c-4593-869c-72febe89dfe0",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/decisions.yaml\\\", \\\"content\\\": \\\"_next_id: 63\\\\ndecisions:\\\\n- id: D001\\\\n  date: 2026-05-13 17:44 UTC\\\\n  summary: MVP 方案：用 Interaction Index 跨 phase 差异验证核心假设\\\\n  rationale: 评审建议 novelty 锚定在 \\\\\\\"phase-dependent interaction direction reversal\\\\\\\"。MVP\\\\n    聚焦验证这一点：在 MATH-500 子集上 profiling DeepSeek-R1-Distill-Qwen-7B，用 ThinKV 方法切分 phases，计算\\\\n    attention × KV 的 Interaction Index。比全 grid search 更聚焦，直接验证核心 novelty 锚点。Pass =\\\\n    II 跨 phase 显著不同；Fail = II 恒定。预计 10-15 H100-hours。\\\\n  related_experiments: []\\\\n  depends_on: []\\\\n- id: D002\\\\n  date: 2026-05-13 17:48 UTC\\\\n  summary: 向 Manager 申请 4×H100-80GB 租卡，预计 8-10 天，¥3200-5000\\\\n  rationale: 12 天截稿，4 GPU 并行可将日历时间压到 ~8 天（留 4 天 buffer）。2 GPU 需 11 天，buffer 不足 1 天，风险过高。用户明确授权\\\\\\\"几张都可以\\\\\\\"。GPU\\\\n    就绪 hard deadline 5/14 EOD。\\\\n  related_experiments: []\\\\n  depends_on:\\\\n  - D001\\\\n- id: D003\\\\n  date: 2026-05-13 17:54 UTC\\\\n  summary: Throughput 策略：RTX 6000 Pro 做开发/accuracy，最终 throughput 短租 H100\\\\n  rationale: IDEA_BRIEF 硬约束要求\\\\\\\"Report wall-clock and throughput on H100\\\\\\\"，baseline 论文（Polar\\\\n    Sparsity、SeerAttention-R）均报告 H100 数字。RTX 6000 Pro (sm_89) vs H100 (sm_90) 的 kernel\\\\n    speedup 可能不同。策略(a)：RTX 6000 Pro 做全部开发+accuracy+ablation（硬件无关），仅 throughput 基准测试短租\\\\n    H100 ~2-4h（~$6-12）。比策略(b)全在 RTX 6000 Pro 上报告更有说服力，成本极低。H100 在 M5 阶段再申请。\\\\n  related_experiments: []\\\\n  depends_on:\\\\n  - D002\\\\n- id: D004\\\\n  date: 2026-05-13 17:58 UTC\\\\n  summary: Throughput benchmark 硬件从 H100 改为 H20（Hopper sm_90，用户确认无 H100 可用）\\\\n  rationale: H20 与 H100 同为 Hopper sm_90，kernel 兼容无需额外适配。96GB HBM3 + 4TB/s 带宽适合 inference\\\\n    benchmark。在 H20 上重跑所有 baseline 确保公平比较，报告 relative speedup ratio（Hopper 架构内比值稳定）。H100\\\\n    不可用，H20 是最佳替代。\\\\n  related_experiments: []\\\\n  depends_on:\\\\n  - D003\\\\n- id: D005\\\\n  date: 2026-05-13 18:01 UTC\\\\n  summary: GPU 从 4× RTX 6000 Pro 换为 4× H20-NVLink 96GB\\\\n  rationale: H20 是 Hopper sm_90（与 H100 同架构），kernel 无需跨架构适配。4TB/s HBM3 带宽远优于 RTX 6000\\\\n    Pro（~960GB/s），7B 推理速度接近 H100。全程同架构消除 M5+ 短租需求，简化流程。用户主动提出可换 H20。\\\\n  related_experiments: []\\\\n  depends_on:\\\\n  - D004\\\\n- id: D006\\\\n  date: 2026-05-13 18:40 UTC\\\\n  summary: GPU 实际为 Blackwell sm_100+（非 Ada sm_89）：MVP 不阻塞，kernel/throughput 阶段需 Hopper\\\\n  rationale: nvidia-smi 显示 \\\\\\\"RTX PRO 6000 Blackwell Server Edition\\\\\\\" compute cap 12.0。MVP\\\\n    profiling 仅需 PyTorch forward pass 无架构依赖。M4 kernel integration 阶段 Triton/TileLang\\\\n    对 sm_100+ 支持待验证。M5+ throughput benchmark 仍需 Hopper 架构（H20）做可比测量。先用 Blackwell 推进\\\\n    M1-M3，不阻塞。\\\\n  related_experiments: []\\\\n  depends_on:\\\\n  - D005\\\\n- id: D007\\\\n  date: 2026-05-13 20:20 UTC\\\\n  summary: M1 结果无效（KV bug + KDE 失败）：两路并行——P0 修复重跑 + 替代 segmentation 开发\\\\n  rationale: KV eviction 的 per-layer mask 交集 bug 导致全 NaN（P0），KDE 82% 样本找不到 tri-modal\\\\n    结构（P1）。但积极信号存在：execution phase 对 head pruning 敏感度 474× vs reasoning 14×，说明 token\\\\n    级结构性差异真实存在。决策：(A) P0 修复后重跑 M1 获取有效 II + 诊断数据，(B) 并行开发 GMM+BIC / quantile-based\\\\n    / multi-layer 替代 segmentation。先看重跑 II 是否在现有 3 phase 间有差异，差异显著则 KDE 虽粗糙但假设成立；无差异则上替代方案。\\\\n  related_experiments:\\\\n  - exp_id: mvp_interaction_index_profiling\\\\n    role: failed_run\\\\n    result: KV NaN + KDE 82% fallback + 90% transition\\\\n  depends_on:\\\\n  - D001\\\\n- id: D008\\\\n  date: 2026-05-13 21:23 UTC\\\\n  summary: M1v2 假设未获支持但测量方法有问题——M1v3 最后诊断：降 sparsity + quantile segmentation + NaN\\\\n    guard\\\\n  rationale: M1v2 所有 phase 均 super-additive、无 sign reversal，但 3 个方法论问题使结论不可靠：(1) 30%\\\\n    random masking 导致 24-33× PPL 退化，超出安全区；(2) KDE 90% fallback，phase 划分无意义；(3) NaN\\\\n    CI artifact 导致虚假 PASS。M1v3 修复这三点后做最终判定。叙事 pivot：即使全 super-additive，magnitude 跨\\\\n    segment 差异（+17.8 vs +3.1）仍支持 phase-aware allocation。Pass = magnitude CI 不重叠；Fail\\\\n    = magnitude 无差异。\\\\n  related_experiments:\\\\n  - exp_id: mvp_ii_profiling_v2\\\\n    role: diagnostic\\\\n    result: All super-additive, no sign reversal, NaN artifact PASS, KDE 90% fallback\\\\n  depends_on:\\\\n  - D007\\\\n- id: D009\\\\n  date: 2026-05-13 22:44 UTC\\\\n  summary: Random masking 系统性混淆——v1-v3 测了错误条件；importance-based masking 是正确 MVP 测试，立即启动\\\\n    v4\\\\n  rationale: 三次 MVP 实验全用 random masking（torch.randperm 选 heads/KV），天然产生 super-additive\\\\n    interaction（随机移除组件造成相关性损伤）。初步 importance-vs-random 对比已显示 masking 方法是 II 符号的主导因子（importance\\\\n    II=-0.91 sub-additive vs random II=+9.38 super-additive）。v3 在 clean methodology\\\\n    下仍全 super-additive 是预期结果，不代表 PACS 假设无效。真正的 MVP 判定需在 importance-based masking 条件下测试\\\\n    per-phase II——这才是实际部署条件下的 compound sparsity 行为。v3 high vs mid 在 s=0.2 下 CI 几乎不重叠（[1.06,3.55]\\\\n    vs [-1.06,1.30]），暗示 importance-based 下 magnitude 差异可能更显著。\\\\n  related_experiments:\\\\n  - exp_id: mvp_ii_profiling_v3\\\\n    role: evidence\\\\n    result: negative under random masking, but confirms methodology is sound\\\\n  - exp_id: mvp_ii_profiling_v2\\\\n    role: evidence\\\\n    result: negative, methodology issues identified and fixed in v3\\\\n  - exp_id: mvp_interaction_index_profiling\\\\n    role: evidence\\\\n    result: failed (bugs), but importance-vs-random preliminary data is key signal\\\\n  depends_on:\\\\n  - D008\\\\n- id: D010\\\\n  date: 2026-05-13 22:44 UTC\\\\n  summary: MVP FAIL on phase-dependent reversal; PIVOT to strategy-dependent direction\\\\n    reversal as core novelty\\\\n  rationale: 三轮 MVP 实验（v1 bug/v2 negative/v3 negative）确认 phase-dependent direction\\\\n    reversal 不存在——所有 phase 均 super-additive，v2 的 5.8x magnitude 差异是 KDE 不均衡 artifact。但\\\\n    importance vs random masking 数据发现 strategy-dependent direction reversal：random\\\\n    30% II=+9.38（super-additive）vs importance 30% II=-0.91（sub-additive），20% 也有符号反转。这是更干净、更强的\\\\n    novelty 锚点，直接 motivate learned compound controller。Pivot 方向：以 strategy-dependent\\\\n    interaction reversal 为核心 claim，phase conditioning 降为可选的二级贡献。\\\\n  related_experiments:\\\\n  - exp_id: mvp_interaction_index_profiling\\\\n    role: initial MVP (bugged)\\\\n    result: failed\\\\n  - exp_id: mvp_ii_profiling_v2\\\\n    role: P0 fix rerun\\\\n    result: negative - no direction reversal\\\\n  - exp_id: mvp_ii_profiling_v3\\\\n    role: low sparsity + quantile segmentation\\\\n    result: negative - no magnitude difference\\\\n  depends_on:\\\\n  - D008\\\\n  - D007\\\\n  - D001\\\\n- id: D011\\\\n  date: 2026-05-14 01:00 UTC\\\\n  summary: Float16 NaN→II bias discovered at s≥0.3; fix to float32 forward, don't\\\\n    pause running batch\\\\n  rationale: Agent 发现 head masking hook 中 inf×0→NaN 导致高 sparsity 下 both_ppl 为 NaN，II\\\\n    聚合排除这些 segment 造成系统性偏差。当前 batch (s025/s035/v4d) 保持运行作为 float16 reference，并行实施\\\\n    float32 修复，完成后重跑。Random masking 不受影响。\\\\n  related_experiments:\\\\n  - exp_id: mvp_v4_legacy_s035\\\\n    role: affected\\\\n    result: running, float16 results may be biased\\\\n  - exp_id: mvp_ii_profiling_v4d\\\\n    role: affected\\\\n    result: running, float16 results may be biased\\\\n  - exp_id: mvp_v4_legacy_s025\\\\n    role: reference\\\\n    result: running, likely unaffected at s=0.25\\\\n  - exp_id: mvp_v4_random_r2\\\\n    role: control\\\\n    result: running, unaffected by this bug\\\\n  depends_on:\\\\n  - D010\\\\n- id: D012\\\\n  date: 2026-05-14 01:07 UTC\\\\n  summary: 暂停 importance-based 实验规划，紧急审查 KV importance metric 正确性\\\\n  rationale: 'Reviewer 发现 importance-based KV eviction 的 PPL 退化比 random eviction 严重\\\\n    26-60 倍（s=0.3: 408.98 vs 6.77），完全反直觉。cumulative_attention_received 作为 importance\\\\n    proxy 可能失效或排序方向有 bug。如果 metric 是坏的，D010 的 strategy-dependent direction reversal\\\\n    是 artifact 而非真实现象，整个 importance-based 路线需要重新评估。'\\\\n  related_experiments:\\\\n  - exp_id: mvp_v4_random_r2\\\\n    role: evidence\\\\n    result: random baseline 全 super-additive，数据可靠\\\\n  - exp_id: mvp_v4a_r2\\\\n    role: evidence\\\\n    result: importance-based kv_ppl 异常高，26-60x worse than random\\\\n  depends_on:\\\\n  - D010\\\\n- id: D013\\\\n  date: 2026-05-14 01:16 UTC\\\\n  summary: 暂停 importance masking 结论，根因确认：cumulative_attention_received 有因果注意力位置偏差，驱逐最近上下文导致灾难性退化\\\\n  rationale: Reviewer 根因分析确认：causal attention 中 position 0 被 N-1 个 token 关注（累积最高），position\\\\n    N-1 仅被自身关注（累积最低）。topk(largest=False) 驱逐最低分 = 驱逐最新位置 = 破坏最近上下文。这解释了 importance\\\\n    eviction 比 random 差 26-60× 的现象。s025 的 II per-sample mean (+152.7) 与聚合计算 (-107.6)\\\\n    符号相反，CI 宽 455 单位，统计意义为零。D010 的 strategy-dependent direction reversal 可能完全是坏指标伪影。修复方向：position\\\\n    normalization importance[j] /= (seq_len - j)。\\\\n  related_experiments:\\\\n  - exp_id: mvp_v4_legacy_s025\\\\n    role: evidence\\\\n    result: II=+152.7 但聚合计算=-107.6，符号矛盾\\\\n  - exp_id: mvp_v4_legacy_s035\\\\n    role: evidence\\\\n    result: II=-462.7, CI=[-1557,+101]，极不稳定\\\\n  - exp_id: mvp_ii_profiling_v4d\\\\n    role: failed\\\\n    result: 5/50后静默崩溃，疑似OOM\\\\n  depends_on:\\\\n  - D010\\\\n- id: D014\\\\n  date: 2026-05-14 02:19 UTC\\\\n  summary: D010 pivot hypothesis NEGATIVE; 新发现 phase-modulated severity gradient (28x-1633x);\\\\n    选定 Framing A 进入 research\\\\n  rationale: v5 修复后 4 个 sparsity level 全部 super-additive，strategy-dependent reversal\\\\n    不成立（v4 负值为 NaN 伪影）。但数据揭示更强信号：importance eviction 下 phase gradient 达 1633x（s=0.30），random\\\\n    仅 1.8x。这是无先行文献报告的 novel finding。选方案 A \\\\\\\"Phase-Modulated Compound Interaction Severity\\\\\\\"：(1)\\\\n    数据最强力支撑 (2) 与 SparK (AAAI'26) 差异化（他们没看 phase 维度）(3) 直接导出 phase-gated controller\\\\n    作为系统贡献。需注意 s=0.30 low phase 存在 heavy tail（mean=1926 vs median=44.63），论文需报告 robust\\\\n    statistics。\\\\n  related_experiments:\\\\n  - exp_id: mvp_v5_fixed_s015\\\\n    role: validation\\\\n    result: positive - phase gradient 28x\\\\n  - exp_id: mvp_v5_fixed_s020\\\\n    role: validation\\\\n    result: positive - phase gradient 64x\\\\n  - exp_id: mvp_v5_fixed_s025\\\\n    role: validation\\\\n    result: positive - phase gradient 114x\\\\n  - exp_id: mvp_v5_fixed_s030\\\\n    role: validation\\\\n    result: positive - phase gradient 1633x\\\\n  - exp_id: mvp_v4_random_r2\\\\n    role: baseline\\\\n    result: random gradient <2x across all sparsity\\\\n  depends_on:\\\\n  - D013\\\\n  - D010\\\\n- id: D015\\\\n  date: 2026-05-14 03:00 UTC\\\\n  summary: 'GO: Phase-modulated severity confirmed (median gradient 12.8x-74.9x importance\\\\n    vs ~1x random), proceed to M1'' bootstrap CI + cross-model'\\\\n  rationale: 四个 sparsity level 的 importance median gradient 单调递增（12.8x→28.7x→52.9x→74.9x），random\\\\n    baseline 恒定 ~1x。Phase-strategy interaction 是 importance masking 特异性现象，非 compound\\\\n    sparsity 通用属性。Crossover pattern（importance 在 high phase 更安全、low phase 更危险）提供额外\\\\n    motivation。Go/no-go 标准满足：importance median gradient 显著 > random median gradient。叙事锚定\\\\n    median（mean 因 s030 heavy tail 膨胀 21.8x）。\\\\n  related_experiments:\\\\n  - exp_id: mvp_v5_fixed_s015\\\\n    role: importance s=0.15\\\\n    result: median gradient 12.8x\\\\n  - exp_id: mvp_v5_fixed_s020_r2\\\\n    role: importance s=0.20\\\\n    result: median gradient 28.7x\\\\n  - exp_id: mvp_v5_fixed_s025\\\\n    role: importance s=0.25\\\\n    result: median gradient 52.9x\\\\n  - exp_id: mvp_v5_fixed_s030_r2\\\\n    role: importance s=0.30\\\\n    result: median gradient 74.9x\\\\n  - exp_id: mvp_v5_random_s015\\\\n    role: random baseline s=0.15\\\\n    result: gradient 1.14x\\\\n  - exp_id: mvp_v5_random_s025\\\\n    role: random baseline s=0.25\\\\n    result: gradient 0.97x\\\\n  depends_on:\\\\n  - D014\\\\n- id: D016\\\\n  date: 2026-05-14 03:00 UTC\\\\n  summary: 'D015: GO — Phase-modulated severity claim 验证通过，进入 M1'' bootstrap CI +\\\\n    cross-model'\\\\n  rationale: Importance median gradient 单调递增 12.8x→28.7x→52.9x→74.9x（4 sparsity levels），random\\\\n    baseline gradient ≈1x（phase-independent）。Importance/random gradient 比值 11.2x-54.5x，CI\\\\n    不重叠。核心 claim \\\\\\\"importance eviction 下 compound interaction 是 phase-dependent 的\\\\\\\"\\\\n    获实证支撑。叙事锚定 median（mean 因 heavy tail 膨胀，s030 mean/median=43:1）。附带发现：importance\\\\n    产生 phase-selective amplification（高 sparsity phase 反而减少交互，低 sparsity phase 大幅放大），强化\\\\n    phase-gated controller motivation。\\\\n  related_experiments:\\\\n  - exp_id: mvp_v5_fixed_s015\\\\n    role: importance s=0.15\\\\n    result: median gradient 12.8x\\\\n  - exp_id: mvp_v5_fixed_s020_r2\\\\n    role: importance s=0.20\\\\n    result: median gradient 28.7x\\\\n  - exp_id: mvp_v5_fixed_s025\\\\n    role: importance s=0.25\\\\n    result: median gradient 52.9x\\\\n  - exp_id: mvp_v5_fixed_s030_r2\\\\n    role: importance s=0.30\\\\n    result: median gradient 74.9x\\\\n  - exp_id: mvp_v5_random_s015\\\\n    role: random baseline s=0.15\\\\n    result: gradient 1.14x (phase-independent)\\\\n  - exp_id: mvp_v5_random_s025\\\\n    role: random baseline s=0.25\\\\n    result: gradient 0.97x (phase-independent)\\\\n  depends_on:\\\\n  - D014\\\\n- id: D017\\\\n  date: 2026-05-14 04:49 UTC\\\\n  summary: 'D017: Bootstrap CI confirms importance gradient 11-42× (all p=0.0000);\\\\n    launch cross-model + random re-run'\\\\n  rationale: v6 importance 四组 per-problem bootstrap (B=10000) 结果：paired gradient 11.5-41.9×,\\\\n    unpaired 12.7-39.3×, 所有 CI 下界远离 1.0, p=0.0000。Phase-modulated severity claim 统计显著成立。下一步：(1)\\\\n    Qwen2.5-7B cross-model 验证泛化性，(2) 用 v6 代码重跑 random 获取 per_problem_ii 做同粒度对比。论文主表用\\\\n    unpaired bootstrap（n 更大 CI 更窄），paired 放 appendix。4 GPU 并行：2 卡 Qwen importance\\\\n    + 2 卡 random re-run。\\\\n  related_experiments:\\\\n  - exp_id: v6_importance_s015\\\\n    role: primary\\\\n    result: gradient=11.53×, CI=[3.49,23.78]\\\\n  - exp_id: v6_importance_s020\\\\n    role: primary\\\\n    result: gradient=11.05×, CI=[5.42,69.27]\\\\n  - exp_id: v6_importance_s025\\\\n    role: primary\\\\n    result: gradient=35.72×, CI=[9.52,101.54]\\\\n  - exp_id: v6_importance_s030\\\\n    role: primary\\\\n    result: gradient=41.92×, CI=[19.14,299.76]\\\\n  depends_on:\\\\n  - D016\\\\n- id: D018\\\\n  date: 2026-05-14 05:24 UTC\\\\n  summary: Qwen 速度问题为误诊（实际 ~50s/problem），停止 Route B speed fix；NaN overlap 检查为 P0 阻塞项\\\\n  rationale: Reviewer 核实 Qwen 日志发现实际速度 ~50s/problem（与 DeepSeek 相当），之前 37-75min/problem\\\\n    的诊断错误。Kill Qwen 实验的决策基于错误前提。Route B worker 在解决不存在的问题，应停止。NaN overlap 检查决定是否需要\\\\n    bf16 全量重跑，是当前最高优先级阻塞项。\\\\n  related_experiments:\\\\n  - exp_id: qwen_importance_s015\\\\n    role: killed_误诊\\\\n    result: killed\\\\n  - exp_id: qwen_importance_s020\\\\n    role: killed_误诊\\\\n    result: killed\\\\n  - exp_id: qwen_importance_s025\\\\n    role: killed_误诊\\\\n    result: killed\\\\n  - exp_id: qwen_importance_s030\\\\n    role: killed_误诊\\\\n    result: killed\\\\n  depends_on:\\\\n  - D017\\\\n- id: D019\\\\n  date: 2026-05-14 05:31 UTC\\\\n  summary: bf16 全量重跑：NaN 过滤存在选择偏差（15.3% 不一致），fp16 结果不可用于论文 claim\\\\n  rationale: Reviewer 审查发现 s015 vs s030 中 23/150 对 null 状态不一致（ii_mid 不一致率 24%），NaN\\\\n    不仅来自 dense forward（Layer 27），还来自 sparse 条件本身。NaN 过滤会系统性丢弃 sparse 表现最差位置，导致 II\\\\n    估计偏低。bf16 5-problem 验证已通过（仅 1 个合法缺失）。当前 fp16 v6_random 让其跑完（sunk cost），但论文数据必须基于\\\\n    bf16 重跑版本。\\\\n  related_experiments:\\\\n  - exp_id: v6_importance_s015\\\\n    role: affected\\\\n    result: fp16 NaN bias\\\\n  - exp_id: v6_importance_s020\\\\n    role: affected\\\\n    result: fp16 NaN bias\\\\n  - exp_id: v6_importance_s025\\\\n    role: affected\\\\n    result: fp16 NaN bias\\\\n  - exp_id: v6_importance_s030\\\\n    role: affected\\\\n    result: fp16 NaN bias\\\\n  - exp_id: v6_random_s015\\\\n    role: affected\\\\n    result: fp16 NaN bias\\\\n  - exp_id: v6_random_s020\\\\n    role: affected\\\\n    result: fp16 NaN bias\\\\n  - exp_id: v6_random_s025\\\\n    role: affected\\\\n    result: fp16 NaN bias\\\\n  - exp_id: v6_random_s030\\\\n    role: affected\\\\n    result: killed + fp16 NaN bias\\\\n  depends_on: []\\\\n- id: D020\\\\n  date: 2026-05-14 05:35 UTC\\\\n  summary: bf16 全量重跑：16 个实验（DeepSeek + Qwen × importance + random × 4 sparsity），论文数据统一\\\\n    bf16\\\\n  rationale: fp16 NaN 跨条件不一致率 15.3%（NaN overlap 检查确认），null-filter 后存在选择偏差。bf16 验证\\\\n    0 NaN。fp16 vs bf16 数值精度不同导致 token 序列差异，不可混用。全量重跑 ~3h，时间充裕。\\\\n  related_experiments:\\\\n  - exp_id: v6_importance_s015\\\\n    role: affected\\\\n    result: fp16 NaN 需重跑\\\\n  - exp_id: v6_importance_s020\\\\n    role: affected\\\\n    result: fp16 NaN 需重跑\\\\n  - exp_id: v6_importance_s025\\\\n    role: affected\\\\n    result: fp16 NaN 需重跑\\\\n  - exp_id: v6_importance_s030\\\\n    role: affected\\\\n    result: fp16 NaN 需重跑\\\\n  - exp_id: bf16_verify\\\\n    role: evidence\\\\n    result: bf16 消除 NaN，0/50\\\\n  - exp_id: qwen_pilot\\\\n    role: evidence\\\\n    result: Qwen bf16 同样 NaN-free\\\\n  depends_on: []\\\\n- id: D021\\\\n  date: 2026-05-14 05:53 UTC\\\\n  summary: 'Framing constraint D023: super-additivity claim must specify phase-dependent\\\\n    gradient, not mere existence'\\\\n  rationale: 'Reviewer 审查 v6_random_s020 发现 random masking 也产生正 II（mean ~0.9-1.3×），因此论文不能\\\\n    claim \\\\\\\"importance masking produces super-additive interaction\\\\\\\"——random 也有。区分信号是\\\\n    phase-dependent gradient（importance: 跨两个数量级 vs random: ~1× flat）。同时 high_sparsity\\\\n    skewness=-4.83 要求 permutation test 使用 robust statistic。'\\\\n  related_experiments:\\\\n  - exp_id: v6_random_s020\\\\n    role: evidence\\\\n    result: random II positive (~0.9-1.3×) but no phase-dependent gradient — expected\\\\n      baseline behavior\\\\n  depends_on:\\\\n  - D015\\\\n- id: D022\\\\n  date: 2026-05-14 05:58 UTC\\\\n  summary: 'D024: Bootstrap B=1000→10000 修正 + Results 写作 CRITICAL 修复'\\\\n  rationale: Reviewer 发现论文声称 B=10,000 但实际 profiling config 为 n_bootstrap=1000，导致 p\\\\n    < 10^-4 claim 不成立（B=1000 最多 p < 0.001）。修正方案：(1) fp16 参考文本改为 B=1000 + p < 0.001；(2)\\\\n    bf16 重跑全部设 n_bootstrap=10000 以支持更强统计声明。同时修复 results.tex dtype 虚假声明、\\\\\\\\label 冲突、random\\\\n    \\\\\\\"negligible\\\\\\\" 违反 D023 等问题。\\\\n  related_experiments:\\\\n  - exp_id: bf16_importance_s015\\\\n    role: config_update\\\\n    result: n_bootstrap→10000\\\\n  - exp_id: bf16_importance_s020\\\\n    role: config_update\\\\n    result: n_bootstrap→10000\\\\n  - exp_id: bf16_importance_s025\\\\n    role: config_update\\\\n    result: n_bootstrap→10000\\\\n  - exp_id: v6_importance_s020\\\\n    role: evidence\\\\n    result: actual B=1000 confirmed\\\\n  depends_on:\\\\n  - D020\\\\n  - D023\\\\n- id: D023\\\\n  date: 2026-05-14 06:00 UTC\\\\n  summary: Bootstrap B 值修正：fp16 实际 B=1000（非论文误写 10000），bf16 重跑设 n_bootstrap=10000\\\\n  rationale: Reviewer 审查发现 results_5_1.tex 声称 B=10000 但 profiling config 实际为 n_bootstrap=1000。直接后果：(1)\\\\n    p < 10^-4 声明不成立，B=1000 精度上限为 p < 0.001；(2) CI 宽度有差异。修正策略：fp16 参考数据如实标注 B=1000；bf16\\\\n    重跑批次将 n_bootstrap 设为 10000，最终论文基于 bf16 数据可合法声称 B=10000。同时修正 paper_framing.md RC4\\\\n    部分。\\\\n  related_experiments:\\\\n  - exp_id: v6_importance_s020\\\\n    role: evidence\\\\n    result: profiling config confirmed n_bootstrap=1000\\\\n  - exp_id: v6_importance_s030\\\\n    role: evidence\\\\n    result: profiling config confirmed n_bootstrap=1000\\\\n  - exp_id: bf16_importance_s015\\\\n    role: affected\\\\n    result: will use n_bootstrap=10000\\\\n  - exp_id: bf16_importance_s020\\\\n    role: affected\\\\n    result: will use n_bootstrap=10000\\\\n  - exp_id: bf16_importance_s025\\\\n    role: affected\\\\n    result: will use n_bootstrap=10000\\\\n  depends_on:\\\\n  - D020\\\\n  - D019\\\\n- id: D024\\\\n  date: 2026-05-14 06:01 UTC\\\\n  summary: Bootstrap B 值修正：fp16 实际 B=1000（论文误写 10000），bf16 重跑设 n_bootstrap=10000；统一\\\\n    results 文件消除 dtype 矛盾和 label 冲突\\\\n  rationale: 4 份 Reviewer 报告一致标记 CRITICAL：(1) profiling_results.json 确认 n_bootstrap=1000，论文声称\\\\n    B=10000 属数据报告错误，p < 10^-4 不成立（B=1000 上限 p < 0.001）；(2) results.tex 声称 bf16 但数据全为\\\\n    fp16；(3) 两文件 \\\\\\\\label 冲突。修正策略：bf16 重跑时设 n_bootstrap=10000 一劳永逸，final paper 用 bf16\\\\n    数据可合法声称 B=10000。results_5_1.tex 作为 fp16 参考存档，results.tex 为 canonical skeleton，统一\\\\n    label。\\\\n  related_experiments:\\\\n  - exp_id: v6_importance_s020\\\\n    role: evidence\\\\n    result: profiling config confirms n_bootstrap=1000\\\\n  - exp_id: v6_importance_s030\\\\n    role: evidence\\\\n    result: profiling config confirms n_bootstrap=1000\\\\n  - exp_id: bf16_importance_s015\\\\n    role: fix_target\\\\n    result: set n_bootstrap=10000\\\\n  - exp_id: bf16_importance_s020\\\\n    role: fix_target\\\\n    result: set n_bootstrap=10000\\\\n  - exp_id: bf16_importance_s025\\\\n    role: fix_target\\\\n    result: set n_bootstrap=10000\\\\n  depends_on:\\\\n  - D020\\\\n  - D019\\\\n- id: D025\\\\n  date: 2026-05-14 06:27 UTC\\\\n  summary: Claim 锚点从 sign reversal 转为 magnitude gradient——s=0.15 sign reversal 由 outlier\\\\n    驱动，不作为主证据\\\\n  rationale: Reviewer 审查 bf16_importance_s015 发现：high_sparsity mean=-0.150 但 median=+0.006，skewness=-14.99，仅\\\\n    2 个 outlier 拉负。winsorized mean 保留负号但幅度大幅缩小(-0.062)。\\\\\\\"magnitude gradient\\\\\\\"(low >\\\\n    mid > high)在 mean/median/winsorized mean 上均稳健，是更可靠的 claim 锚点。s=0.25 gradient=85.4x\\\\n    更强且无 sign reversal 争议。论文应以 magnitude gradient 为主证据，sign reversal 作为 mean-level\\\\n    次级观察并加 caveat。\\\\n  related_experiments:\\\\n  - exp_id: bf16_importance_s015\\\\n    role: evidence\\\\n    result: sign reversal fragile at mean level; magnitude gradient robust\\\\n  depends_on: []\\\\n- id: D026\\\\n  date: 2026-05-14 06:27 UTC\\\\n  summary: 论文核心证据改用 CI non-overlap + 绝对 II 值，gradient ratio 降级为辅助描述\\\\n  rationale: 'Reviewer 审查发现：(1) gradient_paired_aggregate 因 high_sparsity II 近零（s015:\\\\n    0.00012, s025: 0.01）导致比值膨胀无统计意义；(2) 同一实验不同 gradient 计算方法得 16x vs 69x（s015）或 85x\\\\n    vs 222x（s025），审稿人必攻此不一致。决定：论文主体用三 phase 的 II 绝对值 + bootstrap CI 作为核心证据（CI non-overlap\\\\n    已通过验证），gradient ratio 仅作辅助描述性语言，不作为 headline number。等 s020 bf16 完成后做三点 dose-response\\\\n    分析替代单一 gradient 数字。同时 paper_framing.md 中 \\\\\\\"11-42×\\\\\\\" 数字需在 bf16 全部完成后统一更新为基于 CI 的表述。'\\\\n  related_experiments:\\\\n  - exp_id: bf16_importance_s015\\\\n    role: evidence\\\\n    result: gradient_paired_aggregate=69.24 vs gradient_low_over_abs_high=16.02, 4.3x差异\\\\n  - exp_id: bf16_importance_s025\\\\n    role: evidence\\\\n    result: gradient_paired_aggregate=222.35 vs gradient_low_over_high=85.4, 2.6x差异\\\\n  depends_on:\\\\n  - D015\\\\n  - D023\\\\n- id: D027\\\\n  date: 2026-05-14 06:41 UTC\\\\n  summary: 论文 high-phase II 统一用 median 报告，辅以 winsorized mean，注明 skewness\\\\n  rationale: bf16_importance_s020 的 high-phase skewness=16.67，2 个 outlier 把 raw mean\\\\n    从负拉到 +0.129（winsorized_mean=-0.030, median=0.015）。三个 sparsity level 的 high-phase\\\\n    均存在右偏。用 raw mean 报告会被审稿人攻击为 outlier-driven。统一用 median 反映 central tendency，winsorized\\\\n    mean 作为 robustness check，skewness 作为分布特征注明。\\\\n  related_experiments:\\\\n  - exp_id: bf16_importance_s015\\\\n    role: evidence\\\\n    result: high-phase 同样右偏\\\\n  - exp_id: bf16_importance_s020\\\\n    role: trigger\\\\n    result: skewness=16.67, mean=+0.129 vs winsorized=-0.030\\\\n  - exp_id: bf16_importance_s025\\\\n    role: evidence\\\\n    result: high-phase 跨 sparsity 一致\\\\n  depends_on: []\\\\n- id: D028\\\\n  date: 2026-05-14 06:42 UTC\\\\n  summary: bf16 importance 全系列 4/4 完成，gradient ratio 47-104×，远超 fp16 的 11-42×；s=0.30\\\\n    高 phase CI>0 可作论文叙事亮点\\\\n  rationale: bf16 DeepSeek importance s015-s030 全部 PASS，phase gradient 方向跨 4 个 sparsity\\\\n    level 高度一致。低/高 phase ratio 从 47×(s020) 到 104×(s030) 单调递增，比 fp16 系列的 11-42× 显著更强——bf16\\\\n    消除了数值精度噪声后效应更清晰。s=0.30 是唯一高 phase CI 完全>0 的水平，说明 compound effect 在高 sparsity 下渗透到所有\\\\n    phase，可用于论文叙事。ROADMAP 数字待 bf16 random 对照组完成后统一更新。\\\\n  related_experiments:\\\\n  - exp_id: bf16_importance_s015\\\\n    role: evidence\\\\n    result: PASS, low/high=69× (median)\\\\n  - exp_id: bf16_importance_s020\\\\n    role: evidence\\\\n    result: PASS, low/high=47×\\\\n  - exp_id: bf16_importance_s025\\\\n    role: evidence\\\\n    result: PASS, low/high=85×\\\\n  - exp_id: bf16_importance_s030\\\\n    role: evidence\\\\n    result: PASS, low/high=104×, high CI>0\\\\n  depends_on:\\\\n  - D027\\\\n- id: D029\\\\n  date: 2026-05-14 06:43 UTC\\\\n  summary: v6_random_s030 PASS 是 outlier artifact，permutation test mean→median 修复升为\\\\n    bf16 random 前置阻塞项\\\\n  rationale: Reviewer 审查确认：s030 random 的 Verdict=PASS 由单个 mid-phase extreme segment\\\\n    驱动（attn PPL=382.65，II mean=-230.76）。Median/winsorized mean 下三 phase 平坦（2.4-4.7），与\\\\n    s015/s020/s025 一致。Mean-based permutation test 在高 sparsity 完全不可靠。必须在 bf16 random\\\\n    batch 产出数据前修复 test statistic 为 median-based，否则 bf16 会复现假阳性。论文报告 random baseline\\\\n    统一用 median + winsorized mean。\\\\n  related_experiments:\\\\n  - exp_id: v6_random_s030_r3\\\\n    role: trigger\\\\n    result: PASS is outlier artifact\\\\n  - exp_id: v6_random_s015\\\\n    role: reference\\\\n    result: FAIL (expected)\\\\n  - exp_id: v6_random_s020\\\\n    role: reference\\\\n    result: FAIL (expected)\\\\n  - exp_id: v6_random_s025\\\\n    role: reference\\\\n    result: FAIL (expected)\\\\n  depends_on:\\\\n  - D027\\\\n- id: D030\\\\n  date: 2026-05-14 06:46 UTC\\\\n  summary: Random baseline mean-based II outlier 确认为系统性问题，论文须说明 II heavy-tail 特性及\\\\n    median 选择理由\\\\n  rationale: bf16_ds_rand_s015 复现了 v6_random_s030_r3 的完全一致模式：mid-phase 个别 segment\\\\n    random 移除命中关键 attention head → attn PPL 爆炸 → II mean 被 1-2 个 outlier 主导（mean=-172.66\\\\n    vs median=0.097）。两个独立实验（不同 sparsity、不同精度）出现同样问题，确认系统性。预计 bf16_ds_rand_s020/s025\\\\n    也会出现。论文 methodology 必须明确说明 II 的 heavy-tail 特性 + 为什么使用 median（审稿人看到 mean/median\\\\n    差异 1000× 必问）。Median 数据本身质量正常，fp16/bf16 量级一致。\\\\n  related_experiments:\\\\n  - exp_id: bf16_ds_rand_s015\\\\n    role: trigger\\\\n    result: mean outlier confirmed systemic\\\\n  - exp_id: v6_random_s030_r3\\\\n    role: reference\\\\n    result: first instance of same pattern\\\\n  depends_on:\\\\n  - D029\\\\n- id: D031\\\\n  date: 2026-05-14 06:52 UTC\\\\n  summary: bf16 DeepSeek importance 全系列 4/4 PASS，论文 gradient 报告统一用差值 (II_low - II_high)\\\\n    替代 ratio\\\\n  rationale: bf16 importance s015/s020/s025/s030 全部 verdict=PASS，phase gradient (low>>mid>>high)\\\\n    在所有 sparsity level 稳定成立，跨 sparsity 单调递增，low vs mid CI 不重叠。Median-based ratio gradient（66-276×）因\\\\n    high_median 极小（0.006-0.053）而不稳定，审稿人会质疑近零除法。决定论文和 ROADMAP 统一用差值 (median_low - median_high)\\\\n    报告 gradient，避免 ratio metric 的分母近零问题。差值：s015=0.39, s020=1.49, s025=7.17, s030=14.59——清晰的单调递增趋势，不受除零影响。\\\\n  related_experiments:\\\\n  - exp_id: bf16_importance_s015\\\\n    role: evidence\\\\n    result: PASS, low_median=0.40\\\\n  - exp_id: bf16_importance_s020\\\\n    role: evidence\\\\n    result: PASS, low_median=1.50\\\\n  - exp_id: bf16_importance_s025\\\\n    role: evidence\\\\n    result: PASS, low_median=7.20\\\\n  - exp_id: bf16_importance_s030\\\\n    role: evidence\\\\n    result: PASS, low_median=14.64\\\\n  depends_on:\\\\n  - D029\\\\n  - D030\\\\n- id: D032\\\\n  date: 2026-05-14 07:28 UTC\\\\n  summary: 论文主统计检验改用 difference statistic（ii_low − ii_high），ratio 降为 appendix 辅助\\\\n  rationale: Permutation test 全 4 水平结果：difference statistic 全部 Bonferroni 校正后 p<0.005，效应量单调递增（0.35→1.14→4.02→9.95）。Ratio\\\\n    statistic 受 EPS=0.01 过滤影响，低 sparsity 水平 n_paired 从 49 降至 32-41，s015/s020/s025\\\\n    不显著。Difference 对重尾分布更 robust，不受 EPS 过滤影响，且展示出清晰的 sparsity-severity 单调递增关系——解决了\\\\n    C2 之前的非单调性问题。\\\\n  related_experiments:\\\\n  - exp_id: bf16_importance_s015\\\\n    role: importance_baseline\\\\n    result: PASS\\\\n  - exp_id: bf16_importance_s020\\\\n    role: importance_baseline\\\\n    result: PASS\\\\n  - exp_id: bf16_importance_s025\\\\n    role: importance_baseline\\\\n    result: PASS\\\\n  - exp_id: bf16_importance_s030\\\\n    role: importance_baseline\\\\n    result: PASS\\\\n  - exp_id: bf16_ds_rand_s015\\\\n    role: random_control\\\\n    result: verdict_pending\\\\n  - exp_id: bf16_ds_rand_s020\\\\n    role: random_control\\\\n    result: verdict_pending\\\\n  - exp_id: bf16_ds_rand_s025\\\\n    role: random_control\\\\n    result: verdict_pending\\\\n  - exp_id: bf16_ds_rand_s030\\\\n    role: random_control\\\\n    result: verdict_pending\\\\n  depends_on:\\\\n  - D028\\\\n  - D030\\\\n- id: D033\\\\n  date: 2026-05-14 07:45 UTC\\\\n  summary: 弃用所有 ratio 指标，论文主指标改为 median difference + Cohen's d；registry gradient_paired_aggregate\\\\n    字段定义不一致已确认\\\\n  rationale: 溯源调查发现 registry 中 gradient_paired_aggregate 字段计算方式跨 sparsity 不一致（s015/s025\\\\n    用 median ratio，s020/s030 用 mean difference），导致 \\\\\\\"47-104×\\\\\\\" 不可溯源。根因：ratio 在 high-phase\\\\n    II 接近 0 时不稳定（29-49% 样本 < EPS=0.01）。替代方案 median difference 单调递增（0.39→1.48→7.16→14.59），Cohen's\\\\n    d 同样单调（0.60→0.72→0.95→1.12），与 D032 permutation test difference statistic 一致。论文全面弃用\\\\n    ratio 类指标。\\\\n  related_experiments:\\\\n  - exp_id: bf16_importance_s015\\\\n    role: source_data\\\\n    result: gradient_paired_aggregate=69.24 (median ratio)\\\\n  - exp_id: bf16_importance_s020\\\\n    role: source_data\\\\n    result: gradient_paired_aggregate=5.90 (mean difference, mislabeled)\\\\n  - exp_id: bf16_importance_s025\\\\n    role: source_data\\\\n    result: gradient_paired_aggregate=222.35 (median ratio, inflated by small denominator)\\\\n  - exp_id: bf16_importance_s030\\\\n    role: source_data\\\\n    result: gradient_paired_aggregate=57.24 (mean difference, mislabeled)\\\\n  depends_on:\\\\n  - D032\\\\n  - D028\\\\n- id: D034\\\\n  date: 2026-05-14 07:55 UTC\\\\n  summary: 'C5 cross-model replication confirmed: Qwen2.5-7B-Instruct bf16 importance\\\\n    4/4 PASS，median difference 单调递增 0.039→2.943'\\\\n  rationale: Qwen bf16 importance 全 4 水平 PASS，median difference 单调递增（0.039→0.235→1.268→2.943），与\\\\n    DeepSeek 模式一致（0.39→14.59），magnitude 约为 DeepSeek 1/5。CI non-overlap 在所有 4 个 sparsity\\\\n    level 成立。跨模型方向一致性强，C5 claim 可以成立。\\\\n  related_experiments:\\\\n  - exp_id: bf16_qw_imp_s015\\\\n    role: cross_model_replication\\\\n    result: PASS, diff=0.039\\\\n  - exp_id: bf16_qw_imp_s020\\\\n    role: cross_model_replication\\\\n    result: PASS, diff=0.235\\\\n  - exp_id: bf16_qw_imp_s025\\\\n    role: cross_model_replication\\\\n    result: PASS, diff=1.268\\\\n  - exp_id: bf16_qw_imp_s030\\\\n    role: cross_model_replication\\\\n    result: PASS, diff=2.943\\\\n  depends_on:\\\\n  - D032\\\\n  - D033\\\\n- id: D035\\\\n  date: 2026-05-14 08:01 UTC\\\\n  summary: Cohen's d 修正：实际值 0.44→0.80（旧 claim 0.60→1.12 偏高 25-30%），单调递增趋势不变，叙事改为\\\\\\\"small→large\\\\n    effect size gradient\\\\\\\"\\\\n  rationale: Agent 用 paired Cohen's d (n=49, B=10000 bootstrap CI) 重新计算，发现 D033 中的数字无实际计算来源。实际\\\\n    s015=0.44(small), s020=0.52(medium), s025=0.68(medium), s030=0.80(large)。趋势正确但绝对值需修正。论文必须引用实际计算值。\\\\n  related_experiments:\\\\n  - exp_id: bf16_importance_s015\\\\n    role: source\\\\n    result: d=0.44\\\\n  - exp_id: bf16_importance_s020\\\\n    role: source\\\\n    result: d=0.52\\\\n  - exp_id: bf16_importance_s025\\\\n    role: source\\\\n    result: d=0.68\\\\n  - exp_id: bf16_importance_s030\\\\n    role: source\\\\n    result: d=0.80\\\\n  depends_on:\\\\n  - D033\\\\n- id: D036\\\\n  date: 2026-05-14 08:02 UTC\\\\n  summary: Cohen's d 修正：实际 0.44→0.52→0.68→0.80（D033 声称 0.60→1.12 高估 35-45%），单调递增趋势不变，论文引用新值\\\\n  rationale: Agent 用 paired Cohen's d_z + bootstrap CI(B=10000) 重新计算，Reviewer 审查 PASS。D033\\\\n    原值无计算来源。新值全部 CI 下界>0（显著），small→large 效应量递增与 sparsity-severity 叙事一致。论文需引用 cohens_d_bf16.json\\\\n    中的实际数值。\\\\n  related_experiments:\\\\n  - exp_id: bf16_importance_s015\\\\n    role: source\\\\n    result: d=0.44 [0.35,0.78]\\\\n  - exp_id: bf16_importance_s020\\\\n    role: source\\\\n    result: d=0.52 [0.43,0.90]\\\\n  - exp_id: bf16_importance_s025\\\\n    role: source\\\\n    result: d=0.68 [0.56,0.86]\\\\n  - exp_id: bf16_importance_s030\\\\n    role: source\\\\n    result: d=0.80 [0.67,1.02]\\\\n  depends_on:\\\\n  - D033\\\\n- id: D037\\\\n  date: 2026-05-14 08:05 UTC\\\\n  summary: 'Qwen Cohen''s d: 0.28→1.02 单调递增，但 s015 CI 含 0 不显著。叙事调整为 threshold 差异化——Qwen\\\\n    s≥0.20, DeepSeek s≥0.15'\\\\n  rationale: Reviewer 审查确认 Qwen s015 d=0.28 CI=[-0.006, 0.60] 在 95% 水平不显著。s020-s030\\\\n    全部显著且单调递增(0.55→0.89→1.02)。Qwen 高端效应量反超 DeepSeek(0.89/1.02 vs 0.68/0.80)因方差更低。叙事改为\\\\n    threshold 差异化表述，比统一 claim 更精确更 robust。n_skipped=4(8%) 需论文注明。\\\\n  related_experiments:\\\\n  - exp_id: bf16_qw_imp_s015\\\\n    role: source\\\\n    result: d=0.28 CI含0 不显著\\\\n  - exp_id: bf16_qw_imp_s020\\\\n    role: source\\\\n    result: d=0.55 显著\\\\n  - exp_id: bf16_qw_imp_s025\\\\n    role: source\\\\n    result: d=0.89 显著\\\\n  - exp_id: bf16_qw_imp_s030\\\\n    role: source\\\\n    result: d=1.02 显著\\\\n  depends_on:\\\\n  - D035\\\\n  - D034\\\\n- id: D038\\\\n  date: 2026-05-14 08:06 UTC\\\\n  summary: 'Qwen Cohen''s d: 0.28→1.02，s015 不显著(CI含0)。论文 dose-response claim 改为 \\\\\\\"s≥0.20\\\\n    for Qwen, s≥0.15 for DeepSeek\\\\\\\"，s015 行加注'\\\\n  rationale: Qwen s015 d=0.28 CI=[-0.006,0.60] 不显著；s020-s030 全显著且效应量反超 DeepSeek(s025:0.89vs0.68,\\\\n    s030:1.02vs0.80)。处理策略：(1) cross-model 表 s015 行注明 Qwen 不显著；(2) 叙事用 model-specific\\\\n    threshold 角度：compound interaction onset threshold 因模型而异，DeepSeek s≥0.15 即可观测，Qwen\\\\n    需 s≥0.20；(3) 这反而支持一个更细致的 claim——threshold 差异可能与模型的 attention head redundancy 有关。n_skipped=4(8%)\\\\n    需注明有效样本量。\\\\n  related_experiments:\\\\n  - exp_id: bf16_qw_imp_s015\\\\n    role: source\\\\n    result: d=0.28 non-significant\\\\n  - exp_id: bf16_qw_imp_s020\\\\n    role: source\\\\n    result: d=0.55\\\\n  - exp_id: bf16_qw_imp_s025\\\\n    role: source\\\\n    result: d=0.89\\\\n  - exp_id: bf16_qw_imp_s030\\\\n    role: source\\\\n    result: d=1.02\\\\n  depends_on:\\\\n  - D035\\\\n  - D034\\\\n- id: D039\\\\n  date: 2026-05-14 08:32 UTC\\\\n  summary: n_bootstrap=1000 处理策略：优先尝试从原始数据 re-bootstrap B=10000，否则论文如实标注 B=1,000\\\\n  rationale: 'D023 决定 bf16 实验用 B=10000，但实际所有 bf16 profiling 均为 B=1000。Cohen''s d 已用\\\\n    B=10000 不受影响。PASS/FAIL 判定在 B=1000 下有效。最优方案：检查 profiling_results.json 是否保存了 raw\\\\n    per-sample II 值，若有则用脚本 re-bootstrap B=10000（分钟级完成，不需重跑实验）；若无原始数据则论文如实标注 profiling\\\\n    CI: B=1,000 (p<0.001), Cohen''s d CI: B=10,000。'\\\\n  related_experiments:\\\\n  - exp_id: bf16_ds_imp_s015\\\\n    role: affected\\\\n    result: B=1000\\\\n  - exp_id: bf16_ds_imp_s030\\\\n    role: affected\\\\n    result: B=1000\\\\n  - exp_id: bf16_qw_imp_s015\\\\n    role: affected\\\\n    result: B=1000\\\\n  - exp_id: bf16_qw_imp_s020\\\\n    role: affected\\\\n    result: B=1000\\\\n  depends_on:\\\\n  - D023\\\\n  - D024\\\\n- id: D040\\\\n  date: 2026-05-14 08:32 UTC\\\\n  summary: Qwen random gradient 论文表述修正：不可声称 \\\\\\\"no phase gradient\\\\\\\"，应表述为统计不显著\\\\n  rationale: Qwen random 三组实验 gradient 均非零（0.050/0.129/0.660），s015 甚至 random > importance（0.050\\\\n    vs 0.039）。与 DeepSeek random 的清晰分离（13-39×）不同，Qwen 分离度仅 0.8-1.9×。CI overlap test\\\\n    正确判定 FAIL，结论有效。但论文 §5 需讨论：(1) 低 sparsity 下两种方法的 phase 效应均弱且不可区分；(2) 正确表述为 \\\\\\\"random\\\\n    gradient 不具统计显著性\\\\\\\" 而非 \\\\\\\"random 无 gradient\\\\\\\"。\\\\n  related_experiments:\\\\n  - exp_id: bf16_qw_rand_s015\\\\n    role: evidence\\\\n    result: FAIL, gradient=0.050\\\\n  - exp_id: bf16_qw_rand_s020\\\\n    role: evidence\\\\n    result: FAIL, gradient=0.129\\\\n  - exp_id: bf16_qw_rand_s025\\\\n    role: evidence\\\\n    result: FAIL, gradient=0.660\\\\n  - exp_id: bf16_qw_imp_s015\\\\n    role: comparison\\\\n    result: gradient=0.039, Cohen's d=0.28\\\\n  depends_on:\\\\n  - D037\\\\n  - D038\\\\n- id: D041\\\\n  date: 2026-05-14 08:45 UTC\\\\n  summary: 'CRITICAL: Qwen random s030 PASS (gradient 4.241 > importance 2.943)——borderline，立即\\\\n    B=10000 re-bootstrap 验证'\\\\n  rationale: bf16_qw_rand_s030 CI overlap test PASS，random gradient (4.241) > importance\\\\n    gradient (2.943)。但 CI gap 仅 0.161（极 borderline），且 n_bootstrap=1000（D023 要求 10000）。B=10000\\\\n    的更窄 CI 可能翻转为 FAIL。DeepSeek random s030 gradient=1.538 仍 FAIL（importance/random\\\\n    分离>10×），问题仅限 Qwen s030。两种应对路径：(1) B=10000 re-bootstrap 后 FAIL → 维持原叙事，注明 B=1000\\\\n    时 borderline；(2) B=10000 后仍 PASS → 论文叙事调整为\\\\\\\"moderate sparsity 下 importance 特有，extreme\\\\n    sparsity 下两策略收敛\\\\\\\"，与 entropy-discrimination collapse 机制一致（极高 sparsity 下 head pruning\\\\n    损伤压倒策略差异）。\\\\n  related_experiments:\\\\n  - exp_id: bf16_qw_rand_s030\\\\n    role: trigger\\\\n    result: PASS, gradient=4.241\\\\n  - exp_id: bf16_qw_imp_s030\\\\n    role: comparison\\\\n    result: PASS, gradient=2.943\\\\n  - exp_id: bf16_ds_rand_s030\\\\n    role: cross-model\\\\n    result: FAIL, gradient=1.538\\\\n  depends_on:\\\\n  - D034\\\\n  - D039\\\\n  - D040\\\\n- id: D042\\\\n  date: 2026-05-14 08:53 UTC\\\\n  summary: D041 更新：Qwen random s030 B=10000 后 Cohen's d≈0，aggregate PASS 但无 within-problem\\\\n    consistency，critical 降级 warning\\\\n  rationale: B=10000 re-bootstrap 后：(1) median_diff 从 4.241 降至 2.418，现在小于 importance\\\\n    的 2.943；(2) Cohen's d = -0.035（importance 为 1.02），说明 random 的 aggregate gradient\\\\n    来自 between-problem variability 而非 within-problem phase effect；(3) permutation\\\\n    p=0.012，Bonferroni 校正后 borderline（阈值 0.0125）。论文叙事策略：主用 Cohen's d 作为 importance\\\\n    vs random 的判别指标（1.02 vs ~0，无争议），承认 Qwen s030 aggregate median 有弱趋势但无 within-problem\\\\n    consistency，与 entropy-discrimination collapse 机制一致——extreme sparsity 下 between-problem\\\\n    variability 增大但不形成系统性 phase effect。\\\\n  related_experiments:\\\\n  - exp_id: bf16_qw_rand_s030\\\\n    role: trigger\\\\n    result: PASS verdict retained, but Cohen's d=-0.035, median_diff=2.418\\\\n  - exp_id: bf16_qw_imp_s030\\\\n    role: comparison\\\\n    result: Cohen's d=1.02, gradient=2.943\\\\n  depends_on:\\\\n  - D041\\\\n  - D040\\\\n  - D038\\\\n- id: D043\\\\n  date: 2026-05-14 08:59 UTC\\\\n  summary: D041 结论：B=10000 re-bootstrap 后 bf16_qw_rand_s030 仍 PASS (gradient 2.418)，但\\\\n    Cohen's d≈0——效应量可忽略，叙事可防御\\\\n  rationale: B=10000 re-bootstrap 将 gradient 从 4.241 降至 2.418（CI 收窄），verdict 仍 PASS。但\\\\n    Cohen's d ≈ 0 表明无实际意义的效应量。对比 Qwen importance s030 Cohen's d=1.02，两者差异巨大。论文叙事策略：(1)\\\\n    Table 中标注 QW random s030 为 \\\\\\\"borderline PASS, d≈0\\\\\\\"；(2) §5 讨论：CI test 敏感到 borderline\\\\n    显著但效应量可忽略；(3) 与 importance 的 dose-response gradient（d=0.28→1.02）形成对比——random 即使\\\\n    borderline PASS 也无 dose-response 模式。DeepSeek random 全 4 水平均 FAIL，问题仅限 Qwen s030\\\\n    单个数据点。\\\\n  related_experiments:\\\\n  - exp_id: bf16_qw_rand_s030\\\\n    role: trigger\\\\n    result: PASS, gradient=2.418, Cohen's d≈0\\\\n  - exp_id: bf16_qw_imp_s030\\\\n    role: comparison\\\\n    result: PASS, gradient=2.943, Cohen's d=1.02\\\\n  depends_on:\\\\n  - D041\\\\n- id: D044\\\\n  date: 2026-05-14 09:10 UTC\\\\n  summary: 'C4 entropy-discrimination collapse: Qwen s025 符号反转需调查，论文需 cross-model\\\\n    caveat。Gini 效应 model-dependent（Qwen 1/3~1/4 of DeepSeek）。C4 维持 partially_confirmed\\\\n    直到 per-problem 分析完成。'\\\\n  rationale: Reviewer 审查 qwen_c4_entropy 结果发现：(1) Entropy Δ 6/8 configurations 方向一致但\\\\n    Qwen s025 有符号反转 (+0.0451 vs DeepSeek -0.0446)；(2) Gini 效应 Qwen 远弱于 DeepSeek。不杀\\\\n    C4 但需要 honest reporting + per-problem 分析确认是否 outlier-driven。\\\\n  related_experiments:\\\\n  - exp_id: qwen_c4_entropy\\\\n    role: evidence\\\\n    result: anomaly at s025\\\\n  - exp_id: c4_attention_entropy\\\\n    role: baseline\\\\n    result: DeepSeek all negative\\\\n  depends_on:\\\\n  - D032\\\\n  - D034\\\\n- id: D045\\\\n  date: 2026-05-14 09:17 UTC\\\\n  summary: C4 从 Core Claim 降为 §6 supporting analysis（方案 A）；采用 per-problem paired Cohen's\\\\n    d 作为论文主统计量\\\\n  rationale: qwen_c4_entropy 30/30 完成后结论 negative：entropy-discrimination collapse\\\\n    在 DeepSeek 成立但 Qwen 不复现（s025 符号反转）。论文核心 story 是 phenomenon（phase-dependent severity\\\\n    gradient，C1-C3/C5/C6 全 confirmed），不依赖 mechanism claim。降级 C4 最 defensible，避免 overclaim\\\\n    被审稿人攻击。Cohen's d 采用 per-problem paired 因为实验是 within-subjects 配对设计，segment-level\\\\n    aggregate 放 supplementary 作 robustness check。\\\\n  related_experiments:\\\\n  - exp_id: qwen_c4_entropy\\\\n    role: trigger\\\\n    result: negative — Qwen entropy proxy 不复现 DeepSeek 的 discrimination collapse\\\\n  - exp_id: c4_attention_entropy\\\\n    role: reference\\\\n    result: DeepSeek entropy collapse confirmed\\\\n  - exp_id: bf16_importance_s015\\\\n    role: reference\\\\n    result: B=10000 re-bootstrap completed\\\\n  - exp_id: bf16_importance_s030\\\\n    role: reference\\\\n    result: B=10000 re-bootstrap completed\\\\n  depends_on:\\\\n  - D044\\\\n  - D039\\\\n- id: D046\\\\n  date: 2026-05-14 09:19 UTC\\\\n  summary: 'C4 entropy-collapse 从 Core Claim 降为 §6 supporting analysis（方案 A: model-dependent\\\\n    mechanism）'\\\\n  rationale: Qwen s025 entropy delta 反转(+0.045)、s030 近零，跨模型一致性不成立。但 DeepSeek 四水平一致，且\\\\n    Qwen mid-phase 仅 26 segments 统计功效不足可能是 confound。选方案 A：保留 §6 分析但诚实报告两模型差异，不再作为跨模型通用\\\\n    mechanism claim。核心 empirical claims C1-C3/C5/C6 不受影响。若 s025 调查确认是方差 artifact 可回升强度。\\\\n  related_experiments:\\\\n  - exp_id: qwen_c4_entropy\\\\n    role: primary\\\\n    result: 'C4 cross-model inconsistent: DeepSeek consistent, Qwen partial (s015/s020\\\\n      ok, s025 reversed, s030 near-zero)'\\\\n  - exp_id: worker_analysis_qwen_s025_entropy_investigation\\\\n    role: followup\\\\n    result: completed, pending Agent processing\\\\n  depends_on: []\\\\n- id: D047\\\\n  date: 2026-05-14 09:38 UTC\\\\n  summary: 纳入 6-point dose-response 数据（s=0.10~0.35），限定 II_high<0.06 claim 至 s≤0.30\\\\n  rationale: 6-point 单调性 Spearman ρ=1.0 显著加固 C2+C5。Qwen s=0.10 sub-additive 现象揭示 onset\\\\n    threshold，增加科学深度。DS s=0.35 II_high=0.105 打破原 \\\\\\\"<0.06\\\\\\\" claim，需限定范围。收益（更强证据链）远大于成本（限定一个\\\\n    claim + 加一段 onset 讨论）。\\\\n  related_experiments:\\\\n  - exp_id: bf16_ds_imp_s010\\\\n    role: extension\\\\n    result: near-zero II, monotonicity anchor\\\\n  - exp_id: bf16_ds_imp_s035\\\\n    role: extension\\\\n    result: II_high=0.105, ceiling effect\\\\n  - exp_id: bf16_qw_imp_s010\\\\n    role: extension\\\\n    result: sub-additive II, onset threshold\\\\n  - exp_id: bf16_qw_imp_s035\\\\n    role: extension\\\\n    result: monotonicity confirmed\\\\n  depends_on: []\\\\n- id: D048\\\\n  date: 2026-05-14 09:41 UTC\\\\n  summary: 统一使用 paired d_z (cohens_d_bf16.json) 替换论文全文 independent-samples d\\\\n  rationale: Reviewer CRITICAL：配对数据（同一 problem 的 low/high phase）必须用 paired d_z = mean(diffs)/std(diffs)，论文错误使用了\\\\n    rebootstrap 的 independent-samples d，效应量系统性膨胀 20-40%。Table 4 caption 描述与实际计算不匹配。采用方案\\\\n    A：直接用 cohens_d_bf16.json 已有的 paired d_z 值，修改论文 6 处。主要结论不变。\\\\n  related_experiments: []\\\\n  depends_on: []\\\\n- id: D049\\\\n  date: 2026-05-14 09:55 UTC\\\\n  summary: Table 4 bootstrap CI caption 澄清：改 caption 措辞而非重算 CI\\\\n  rationale: Reviewer 发现 Table 4 bootstrap CI 使用 independent resampling 但 caption\\\\n    写 \\\\\\\"per-problem paired\\\\\\\"。unpaired bootstrap 产生更宽（更保守）的 CI，所有结论方向不变。选择方案 (b)：caption\\\\n    明确 CI 为 independent bootstrap of medians，避免重新计算的成本。优先级低于编译冲刺，编译通过后处理。\\\\n  related_experiments: []\\\\n  depends_on:\\\\n  - D048\\\\n- id: D050\\\\n  date: 2026-05-14 10:03 UTC\\\\n  summary: 回退 fix-cohens-d-notation Worker 的全部修改，恢复 D048 正确的 paired d_z 值\\\\n  rationale: Worker 被文件名 cohens_d_paired_b10000.json 中的 \\\\\\\"paired\\\\\\\" 误导，实际该文件使用 pooled-SD\\\\n    independent-samples d 公式。正确数据源是 cohens_d_bf16.json（compute_cohens_d.py 使用 mean(diffs)/std(diffs,ddof=1)\\\\n    = paired d_z）。符号统一用 \\\\\\\"Cohen's d\\\\\\\" 而非 d_z。\\\\n  related_experiments: []\\\\n  depends_on:\\\\n  - D048\\\\n- id: D051\\\\n  date: 2026-05-14 10:04 UTC\\\\n  summary: 图表全部基于过时数据，需用 bf16 canonical 数据重新生成；删除硬编码脚本 generate_all_figures.py\\\\n  rationale: Reviewer 发现：(1) generate_all_figures.py 硬编码数据与任何分析文件不匹配（G_imp 差数量级），Cohen's\\\\n    d 使用弃用的 independent-samples d；(2) generate_paper_figures.py 读取 v5 旧数据（bootstrap_results_full.json\\\\n    / v6_analysis_results.json），不是 bf16 canonical 数据；(3) figures/ 和 paper_figures/\\\\n    两个目录文件不一致。修复：删除硬编码脚本，用 bf16 profiling_output_bf16_* 数据重新生成所有分析 JSON 和图表，统一输出到\\\\n    paper_figures/。\\\\n  related_experiments: []\\\\n  depends_on:\\\\n  - D048\\\\n  - D050\\\\n- id: D052\\\\n  date: 2026-05-14 13:30 UTC\\\\n  summary: 采纳 Reviewer 审查：C5 pilot-first + heuristic baseline，C2 预注册 s015 ns 叙事，C9\\\\n    仅加引用\\\\n  rationale: Reviewer 独立审查 Round 1 应对方案后建议：(1) C5 先用 1-2 个 sparsity level 做 2h pilot，oracle\\\\n    回收 >30% compound degradation 才全面铺开，否则降为 future work；(2) C5 必须加 simple heuristic\\\\n    baseline（token position ratio 或 cumulative attention entropy 作 phase proxy），与\\\\n    oracle 构成上下界；(3) compute-matched 硬约束；(4) C2 n=500 前预定义\\\\\\\"若 s015 仍 ns 则叙事改为 compound\\\\n    effect emerges above threshold\\\\\\\"；(5) C9 Lethe 仅 Related Work 加一句区分引用，另加 SparK；(6)\\\\n    S3/S7 考虑升级为 C 级；(7) 预留 1 天写 rebuttal letter。\\\\n  related_experiments: []\\\\n  depends_on: []\\\\n- id: D053\\\\n  date: 2026-05-14 14:59 UTC\\\\n  summary: c5b_pilot s_trans cap 澄清：cap 作用于 s_trans 本身（≤0.50），不是 δ'\\\\n  rationale: Reviewer warning 发现 §3.2 公式（δ' cap=0.50）与 handoff checklist（s_trans capped\\\\n    at 0.50）存在歧义。选择解读 B（s_trans ≤ 0.50）：pilot 目的是检测 phase-aware KV modulation 信号存在性，s_trans=0.50\\\\n    已是 substantial modulation；80% KV eviction（解读 A 在 s=0.30 时）可能导致 forward pass 退化，污染后续\\\\n    phase 的 II 计算，引入混淆变量。信号存在后可在 follow-up 中升级探测范围。\\\\n  related_experiments:\\\\n  - exp_id: c5b_pilot\\\\n    role: target\\\\n    result: pending\\\\n  depends_on:\\\\n  - D052\\\\n- id: D054\\\\n  date: 2026-05-14 18:11 UTC\\\\n  summary: II 主指标从 mean 切换为 median + median bootstrap CI\\\\n  rationale: n=500 实验揭示 mean 被极端 outlier 摧毁（rand s015 mean 从 -1.9 暴跌到 -185K，而 median\\\\n    稳定 0.103→0.118）。imp 和 rand 的 outlier 方向相反，mean 虚假放大了效应量。Median 稳定、CI 收窄符合预期，作为\\\\n    heavy-tailed 分布的 robust central tendency 指标。\\\\n  related_experiments:\\\\n  - exp_id: c2_n500_deepseek\\\\n    role: trigger\\\\n    result: rand s015 mean=-185K, median=0.118\\\\n  - exp_id: c1_mvp\\\\n    role: affected\\\\n    result: mean 值需重新评估\\\\n  - exp_id: c3_llama\\\\n    role: affected\\\\n    result: mean 值需重新评估\\\\n  depends_on: []\\\\n- id: D055\\\\n  date: 2026-05-14 18:41 UTC\\\\n  summary: 'c5b_pilot conditional retry: CPU 诊断 root cause → 可修则 c2_n500 GPU 释放后 2h\\\\n    time-box 重试 → 仍失败或不可修则降为 future work'\\\\n  rationale: c5b 5×进程死亡是技术故障非假设否定。论文是 empirical finding paper，mitigation 非核心 claim，framing\\\\n    已有 future work fallback。距截稿 11 天，核心 claims 已 confirmed，诊断无 GPU 成本，若可修则 2h retry\\\\n    有正 EV（加强 RC3 应对）；若不可修则干净收尾。\\\\n  related_experiments:\\\\n  - exp_id: c5b_pilot\\\\n    role: subject\\\\n    result: failed 5×\\\\n  depends_on:\\\\n  - D052\\\\n- id: D056\\\\n  date: 2026-05-14 18:46 UTC\\\\n  summary: 撤回 D055，确认 c5b_pilot gate_failed（非技术故障）：oracle recovery 18% < 30% gate，C5b\\\\n    按 D052 预注册协议降为 future work\\\\n  rationale: D055 基于 Agent 汇报的\\\\\\\"5×进程死亡\\\\\\\"做出 conditional retry 决策，但 Reviewer 核实发现 PID\\\\n    154645 已正常完成 30/30 problems，结果文件存在(51KB)，gate_pass=false 是科学判定（oracle recovery\\\\n    18% < 30%）非技术故障。D052 预注册协议明确\\\\\\\"不达标→future work\\\\\\\"，D055 绕过了此协议。Heuristic recovery 32%\\\\n    > oracle 18% 的反直觉结果 + 两者 CI 均跨零，进一步确认当前 phase-aware allocation 信号不够强。论文 §6 Discussion\\\\n    可提及 pilot 结果（Wilcoxon 显著但效应量不足，方向正确需更精细方法）。\\\\n  related_experiments:\\\\n  - exp_id: c5b_pilot\\\\n    role: subject\\\\n    result: 'gate_failed: oracle recovery 18% < 30% threshold'\\\\n  depends_on:\\\\n  - D052\\\\n  - D055\\\\n- id: D057\\\\n  date: 2026-05-14 18:46 UTC\\\\n  summary: 修正 D055：c5b_pilot 实际已完成(gate_pass=false)，不需要 retry。Registry 改 gate_failed，c5b\\\\n    降为 future work grounding evidence\\\\n  rationale: Reviewer 发现 c5b_pilot PID 154645 于 02:37 UTC 正常完成 30/30 problems，非进程死亡。Oracle\\\\n    recovery 18% < 30% gate，heuristic 32% 但 CI 跨零（统计上不可区分零）。结论：naive phase-aware allocation\\\\n    信号存在（Wilcoxon p=0.002/0.024）但效应量不足，需更精细策略。作为 future work grounding evidence 写入论文\\\\n    §6 Discussion。\\\\n  related_experiments:\\\\n  - exp_id: c5b_pilot\\\\n    role: subject\\\\n    result: gate_failed (oracle 18% < 30% gate, heuristic 32% but CI crosses zero)\\\\n  depends_on:\\\\n  - D055\\\\n  - D052\\\\n- id: D058\\\\n  date: 2026-05-14 18:47 UTC\\\\n  summary: Qwen imp-vs-rand paired 对比 n=50 全部不显著：等 n=500 结果定论，预备 model-dependent magnitude\\\\n    叙事调整\\\\n  rationale: Reviewer 发现 Qwen 在 n=50 下 importance vs random 的 phase gradient paired\\\\n    对比全 4 水平不显著(p>0.07)，DeepSeek 全部高度显著(p≤0.0001)。n=50 对 Qwen 小效应量(d_z 0.09-0.16)功效不足，n=500\\\\n    是预设的功效提升实验。若 n=500 仍不显著，叙事调整为 \\\\\\\"effect magnitude is model-dependent, models with\\\\n    stronger importance discrimination show clearer phase-strategy differentiation\\\\\\\"——与\\\\n    discrimination collapse 机制一致(Qwen importance score 判别力本身较弱)。同时 Qwen mid-phase\\\\n    58% null rate 须在论文中披露 per-phase effective sample sizes。\\\\n  related_experiments:\\\\n  - exp_id: c2_qw_n500\\\\n    role: pending_verification\\\\n    result: running\\\\n  - exp_id: c2_n500_deepseek\\\\n    role: pending_verification\\\\n    result: running\\\\n  depends_on: []\\\\n- id: D059\\\\n  date: 2026-05-14 18:48 UTC\\\\n  summary: d_z 分场景报告：within-importance 保留 d_z，涉及 random 的比较只报 Wilcoxon p + median_diff，不报\\\\n    d_z（outlier 污染）\\\\n  rationale: Random pruning 14.2% catastrophic failure rate（ppl 爆炸至 236K，II min=-4.3M）导致\\\\n    mean-based d_z 不可靠。Within-importance 比较（C2 主结果）两边均为 importance 条件，无此问题，d_z 稳定。分场景处理既保持统计严谨性，又避免\\\\n    deadline 前大规模替换效应量指标。论文加脚注解释 random 不报 d_z 的原因（catastrophic ppl explosion in ~14%\\\\n    of random trials makes mean-based effect size unreliable）。\\\\n  related_experiments:\\\\n  - exp_id: c2_n500_deepseek\\\\n    role: context\\\\n    result: running — n=500 rand s015 outlier rate 14.2%\\\\n  depends_on:\\\\n  - D054\\\\n- id: D060\\\\n  date: 2026-05-14 18:52 UTC\\\\n  summary: C8 从 confirmed 降级为 partially_confirmed（qualitative direction consistent,\\\\n    quantitative interaction weaker）：LLaMA random 也显示 phase gradient，strategy-dependence\\\\n    弱于 DeepSeek/Qwen\\\\n  rationale: Reviewer 独立核实 c3_llama_results.json 发现：(1) within-importance phase gradient\\\\n    强且稳定（d_z~1.0）✓ (2) 但 imp_vs_rand 交互效应弱（d_z 0.19→0.34，仅 s030 Bonferroni 显著）(3)\\\\n    random eviction 在 LLaMA 上也显示非平凡 phase gradient（d_z 0.35→0.44, CI 排除零），与 DeepSeek/Qwen\\\\n    random 7/8 FAIL 模式定性不同。C8 支持 qualitative replication（importance phase gradient\\\\n    方向一致），但 strategy × phase interaction 的量化强度是 architecture-dependent。论文引用 LLaMA\\\\n    数据时必须加限定语，否则审稿人会攻击。\\\\n  related_experiments:\\\\n  - exp_id: c3_llama\\\\n    role: subject\\\\n    result: success but imp_vs_rand interaction weaker than DeepSeek/Qwen; random\\\\n      also shows phase gradient on LLaMA\\\\n  depends_on:\\\\n  - D056\\\\n- id: D061\\\\n  date: 2026-05-14 19:27 UTC\\\\n  summary: D058 已解决：n=500 下 DeepSeek 和 Qwen 的 paired gradient 均达 Bonferroni 显著\\\\n  rationale: s015 分析结果：DeepSeek median_D=-0.4227 p<0.0001 null_rate=10.2%；Qwen median_D=-0.0991\\\\n    p<0.0001 null_rate=45.2%。n=50 时 Qwen 功效不足的问题在 n=500 下完全解决。Qwen null rate 仍高(45.2%)，论文须披露\\\\n    per-phase effective sample size。\\\\n  related_experiments:\\\\n  - exp_id: c2_n500_deepseek\\\\n    role: primary\\\\n    result: significant\\\\n  - exp_id: c2_qw_n500\\\\n    role: primary\\\\n    result: significant\\\\n  depends_on:\\\\n  - D058\\\\n- id: D062\\\\n  date: 2026-05-14 19:37 UTC\\\\n  summary: Cron 监控改为 shell PID + sentinel 双机制，解决 profiling 实验 condition 切换时 PID 变化导致的反复误报\\\\n  rationale: c2_qw_n500 已第 3-4 次 cron 误报，每次触发 diagnose worker 浪费资源。根因：cron 监控 python\\\\n    PID 但 condition 切换时 PID 变化，且 slow path 只识别 tmux 不识别 screen。修复：(1) 改用 shell 脚本\\\\n    PID（全程不变）注册 cron (2) run script 末尾写 sentinel 供 fast path 检测 (3) PID 写入文件供排查。后续\\\\n    profiling 实验模板应默认包含 PID 文件 + sentinel 写入。\\\\n  related_experiments:\\\\n  - exp_id: c2_qw_n500\\\\n    role: trigger\\\\n    result: cron misfire fixed\\\\n  depends_on:\\\\n  - D061\\\\n\\\", \\\"total_chars\\\": 46741, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/decisions.yaml\", \"content\": \"_next_id: 63\\ndecisions:\\n- id: D001\\n  date: 2026-05-13 17:44 UTC\\n  summary: MVP 方案：用 Interaction Index 跨 phase 差异验证核心假设\\n  rationale: 评审建议 novelty 锚定在 \\\"phase-dependent interaction direction reversal\\\"。MVP\\n    聚焦验证这一点：在 MATH-500 子集上 profiling DeepSeek-R1-Distill-Qwen-7B，用 ThinKV 方法切分 phases，计算\\n    attention × KV 的 Interaction Index。比全 grid search 更聚焦，直接验证核心 novelty 锚点。Pass =\\n    II 跨 phase 显著不同；Fail = II 恒定。预计 10-15 H100-hours。\\n  related_experiments: []\\n  depends_on: []\\n- id: D002\\n  date: 2026-05-13 17:48 UTC\\n  summary: 向 Manager 申请 4×H100-80GB 租卡，预计 8-10 天，¥3200-5000\\n  rationale: 12 天截稿，4 GPU 并行可将日历时间压到 ~8 天（留 4 天 buffer）。2 GPU 需 11 天，buffer 不足 1 天，风险过高。用户明确授权\\\"几张都可以\\\"。GPU\\n    就绪 hard deadline 5/14 EOD。\\n  related_experiments: []\\n  depends_on:\\n  - D001\\n- id: D003\\n  date: 2026-05-13 17:54 UTC\\n  summary: Throughput 策略：RTX 6000 Pro 做开发/accuracy，最终 throughput 短租 H100\\n  rationale: IDEA_BRIEF 硬约束要求\\\"Report wall-clock and throughput on H100\\\"，baseline 论文（Polar\\n    Sparsity、SeerAttention-R）均报告 H100 数字。RTX 6000 Pro (sm_89) vs H100 (sm_90) 的 kernel\\n    speedup 可能不同。策略(a)：RTX 6000 Pro 做全部开发+accuracy+ablation（硬件无关），仅 throughput 基准测试短租\\n    H100 ~2-4h（~$6-12）。比策略(b)全在 RTX 6000 Pro 上报告更有说服力，成本极低。H100 在 M5 阶段再申请。\\n  related_experiments: []\\n  depends_on:\\n  - D002\\n- id: D004\\n  date: 2026-05-13 17:58 UTC\\n  summary: Throughput benchmark 硬件从 H100 改为 H20（Hopper sm_90，用户确认无 H100 可用）\\n  rationale: H20 与 H100 同为 Hopper sm_90，kernel 兼容无需额外适配。96GB HBM3 + 4TB/s 带宽适合 inference\\n    benchmark。在 H20 上重跑所有 baseline 确保公平比较，报告 relative speedup ratio（Hopper 架构内比值稳定）。H100\\n    不可用，H20 是最佳替代。\\n  related_experiments: []\\n  depends_on:\\n  - D003\\n- id: D005\\n  date: 2026-05-13 18:01 UTC\\n  summary: GPU 从 4× RTX 6000 Pro 换为 4× H20-NVLink 96GB\\n  rationale: H20 是 Hopper sm_90（与 H100 同架构），kernel 无需跨架构适配。4TB/s HBM3 带宽远优于 RTX 6000\\n    Pro（~960GB/s），7B 推理速度接近 H100。全程同架构消除 M5+ 短租需求，简化流程。用户主动提出可换 H20。\\n  related_experiments: []\\n  depends_on:\\n  - D004\\n- id: D006\\n  date: 2026-05-13 18:40 UTC\\n  summary: GPU 实际为 Blackwell sm_100+（非 Ada sm_89）：MVP 不阻塞，kernel/throughput 阶段需 Hopper\\n  rationale: nvidia-smi 显示 \\\"RTX PRO 6000 Blackwell Server Edition\\\" compute cap 12.0。MVP\\n    profiling 仅需 PyTorch forward pass 无架构依赖。M4 kernel integration 阶段 Triton/TileLang\\n    对 sm_100+ 支持待验证。M5+ throughput benchmark 仍需 Hopper 架构（H20）做可比测量。先用 Blackwell 推进\\n    M1-M3，不阻塞。\\n  related_experiments: []\\n  depends_on:\\n  - D005\\n- id: D007\\n  date: 2026-05-13 20:20 UTC\\n  summary: M1 结果无效（KV bug + KDE 失败）：两路并行——P0 修复重跑 + 替代 segmentation 开发\\n  rationale: KV eviction 的 per-layer mask 交集 bug 导致全 NaN（P0），KDE 82% 样本找不到 tri-modal\\n    结构（P1）。但积极信号存在：execution phase 对 head pruning 敏感度 474× vs reasoning 14×，说明 token\\n    级结构性差异真实存在。决策：(A) P0 修复后重跑 M1 获取有效 II + 诊断数据，(B) 并行开发 GMM+BIC / quantile-based\\n    / multi-layer 替代 segmentation。先看重跑 II 是否在现有 3 phase 间有差异，差异显著则 KDE 虽粗糙但假设成立；无差异则上替代方案。\\n  related_experiments:\\n  - exp_id: mvp_interaction_index_profiling\\n    role: failed_run\\n    result: KV NaN + KDE 82% fallback + 90% transition\\n  depends_on:\\n  - D001\\n- id: D008\\n  date: 2026-05-13 21:23 UTC\\n  summary: M1v2 假设未获支持但测量方法有问题——M1v3 最后诊断：降 sparsity + quantile segmentation + NaN\\n    guard\\n  rationale: M1v2 所有 phase 均 super-additive、无 sign reversal，但 3 个方法论问题使结论不可靠：(1) 30%\\n    random masking 导致 24-33× PPL 退化，超出安全区；(2) KDE 90% fallback，phase 划分无意义；(3) NaN\\n    CI artifact 导致虚假 PASS。M1v3 修复这三点后做最终判定。叙事 pivot：即使全 super-additive，magnitude 跨\\n    segment 差异（+17.8 vs +3.1）仍支持 phase-aware allocation。Pass = magnitude CI 不重叠；Fail\\n    = magnitude 无差异。\\n  related_experiments:\\n  - exp_id: mvp_ii_profiling_v2\\n    role: diagnostic\\n    result: All super-additive, no sign reversal, NaN artifact PASS, KDE 90% fallback\\n  depends_on:\\n  - D007\\n- id: D009\\n  date: 2026-05-13 22:44 UTC\\n  summary: Random masking 系统性混淆——v1-v3 测了错误条件；importance-based masking 是正确 MVP 测试，立即启动\\n    v4\\n  rationale: 三次 MVP 实验全用 random masking（torch.randperm 选 heads/KV），天然产生 super-additive\\n    interaction（随机移除组件造成相关性损伤）。初步 importance-vs-random 对比已显示 masking 方法是 II 符号的主导因子（importance\\n    II=-0.91 sub-additive vs random II=+9.38 super-additive）。v3 在 clean methodology\\n    下仍全 super-additive 是预期结果，不代表 PACS 假设无效。真正的 MVP 判定需在 importance-based masking 条件下测试\\n    per-phase II——这才是实际部署条件下的 compound sparsity 行为。v3 high vs mid 在 s=0.2 下 CI 几乎不重叠（[1.06,3.55]\\n    vs [-1.06,1.30]），暗示 importance-based 下 magnitude 差异可能更显著。\\n  related_experiments:\\n  - exp_id: mvp_ii_profiling_v3\\n    role: evidence\\n    result: negative under random masking, but confirms methodology is sound\\n  - exp_id: mvp_ii_profiling_v2\\n    role: evidence\\n    result: negative, methodology issues identified and fixed in v3\\n  - exp_id: mvp_interaction_index_profiling\\n    role: evidence\\n    result: failed (bugs), but importance-vs-random preliminary data is key signal\\n  depends_on:\\n  - D008\\n- id: D010\\n  date: 2026-05-13 22:44 UTC\\n  summary: MVP FAIL on phase-dependent reversal; PIVOT to strategy-dependent direction\\n    reversal as core novelty\\n  rationale: 三轮 MVP 实验（v1 bug/v2 negative/v3 negative）确认 phase-dependent direction\\n    reversal 不存在——所有 phase 均 super-additive，v2 的 5.8x magnitude 差异是 KDE 不均衡 artifact。但\\n    importance vs random masking 数据发现 strategy-dependent direction reversal：random\\n    30% II=+9.38（super-additive）vs importance 30% II=-0.91（sub-additive），20% 也有符号反转。这是更干净、更强的\\n    novelty 锚点，直接 motivate learned compound controller。Pivot 方向：以 strategy-dependent\\n    interaction reversal 为核心 claim，phase conditioning 降为可选的二级贡献。\\n  related_experiments:\\n  - exp_id: mvp_interaction_index_profiling\\n    role: initial MVP (bugged)\\n    result: failed\\n  - exp_id: mvp_ii_profiling_v2\\n    role: P0 fix rerun\\n    result: negative - no direction reversal\\n  - exp_id: mvp_ii_profiling_v3\\n    role: low sparsity + quantile segmentation\\n    result: negative - no magnitude difference\\n  depends_on:\\n  - D008\\n  - D007\\n  - D001\\n- id: D011\\n  date: 2026-05-14 01:00 UTC\\n  summary: Float16 NaN→II bias discovered at s≥0.3; fix to float32 forward, don't\\n    pause running batch\\n  rationale: Agent 发现 head masking hook 中 inf×0→NaN 导致高 sparsity 下 both_ppl 为 NaN，II\\n    聚合排除这些 segment 造成系统性偏差。当前 batch (s025/s035/v4d) 保持运行作为 float16 reference，并行实施\\n    float32 修复，完成后重跑。Random masking 不受影响。\\n  related_experiments:\\n  - exp_id: mvp_v4_legacy_s035\\n    role: affected\\n    result: running, float16 results may be biased\\n  - exp_id: mvp_ii_profiling_v4d\\n    role: affected\\n    result: running, float16 results may be biased\\n  - exp_id: mvp_v4_legacy_s025\\n    role: reference\\n    result: running, likely unaffected at s=0.25\\n  - exp_id: mvp_v4_random_r2\\n    role: control\\n    result: running, unaffected by this bug\\n  depends_on:\\n  - D010\\n- id: D012\\n  date: 2026-05-14 01:07 UTC\\n  summary: 暂停 importance-based 实验规划，紧急审查 KV importance metric 正确性\\n  rationale: 'Reviewer 发现 importance-based KV eviction 的 PPL 退化比 random eviction 严重\\n    26-60 倍（s=0.3: 408.98 vs 6.77），完全反直觉。cumulative_attention_received 作为 importance\\n    proxy 可能失效或排序方向有 bug。如果 metric 是坏的，D010 的 strategy-dependent direction reversal\\n    是 artifact 而非真实现象，整个 importance-based 路线需要重新评估。'\\n  related_experiments:\\n  - exp_id: mvp_v4_random_r2\\n    role: evidence\\n    result: random baseline 全 super-additive，数据可靠\\n  - exp_id: mvp_v4a_r2\\n    role: evidence\\n    result: importance-based kv_ppl 异常高，26-60x worse than random\\n  depends_on:\\n  - D010\\n- id: D013\\n  date: 2026-05-14 01:16 UTC\\n  summary: 暂停 importance masking 结论，根因确认：cumulative_attention_received 有因果注意力位置偏差，驱逐最近上下文导致灾难性退化\\n  rationale: Reviewer 根因分析确认：causal attention 中 position 0 被 N-1 个 token 关注（累积最高），position\\n    N-1 仅被自身关注（累积最低）。topk(largest=False) 驱逐最低分 = 驱逐最新位置 = 破坏最近上下文。这解释了 importance\\n    eviction 比 random 差 26-60× 的现象。s025 的 II per-sample mean (+152.7) 与聚合计算 (-107.6)\\n    符号相反，CI 宽 455 单位，统计意义为零。D010 的 strategy-dependent direction reversal 可能完全是坏指标伪影。修复方向：position\\n    normalization importance[j] /= (seq_len - j)。\\n  related_experiments:\\n  - exp_id: mvp_v4_legacy_s025\\n    role: evidence\\n    result: II=+152.7 但聚合计算=-107.6，符号矛盾\\n  - exp_id: mvp_v4_legacy_s035\\n    role: evidence\\n    result: II=-462.7, CI=[-1557,+101]，极不稳定\\n  - exp_id: mvp_ii_profiling_v4d\\n    role: failed\\n    result: 5/50后静默崩溃，疑似OOM\\n  depends_on:\\n  - D010\\n- id: D014\\n  date: 2026-05-14 02:19 UTC\\n  summary: D010 pivot hypothesis NEGATIVE; 新发现 phase-modulated severity gradient (28x-1633x);\\n    选定 Framing A 进入 research\\n  rationale: v5 修复后 4 个 sparsity level 全部 super-additive，strategy-dependent reversal\\n    不成立（v4 负值为 NaN 伪影）。但数据揭示更强信号：importance eviction 下 phase gradient 达 1633x（s=0.30），random\\n    仅 1.8x。这是无先行文献报告的 novel finding。选方案 A \\\"Phase-Modulated Compound Interaction Severity\\\"：(1)\\n    数据最强力支撑 (2) 与 SparK (AAAI'26) 差异化（他们没看 phase 维度）(3) 直接导出 phase-gated controller\\n    作为系统贡献。需注意 s=0.30 low phase 存在 heavy tail（mean=1926 vs median=44.63），论文需报告 robust\\n    statistics。\\n  related_experiments:\\n  - exp_id: mvp_v5_fixed_s015\\n    role: validation\\n    result: positive - phase gradient 28x\\n  - exp_id: mvp_v5_fixed_s020\\n    role: validation\\n    result: positive - phase gradient 64x\\n  - exp_id: mvp_v5_fixed_s025\\n    role: validation\\n    result: positive - phase gradient 114x\\n  - exp_id: mvp_v5_fixed_s030\\n    role: validation\\n    result: positive - phase gradient 1633x\\n  - exp_id: mvp_v4_random_r2\\n    role: baseline\\n    result: random gradient <2x across all sparsity\\n  depends_on:\\n  - D013\\n  - D010\\n- id: D015\\n  date: 2026-05-14 03:00 UTC\\n  summary: 'GO: Phase-modulated severity confirmed (median gradient 12.8x-74.9x importance\\n    vs ~1x random), proceed to M1'' bootstrap CI + cross-model'\\n  rationale: 四个 sparsity level 的 importance median gradient 单调递增（12.8x→28.7x→52.9x→74.9x），random\\n    baseline 恒定 ~1x。Phase-strategy interaction 是 importance masking 特异性现象，非 compound\\n    sparsity 通用属性。Crossover pattern（importance 在 high phase 更安全、low phase 更危险）提供额外\\n    motivation。Go/no-go 标准满足：importance median gradient 显著 > random median gradient。叙事锚定\\n    median（mean 因 s030 heavy tail 膨胀 21.8x）。\\n  related_experiments:\\n  - exp_id: mvp_v5_fixed_s015\\n    role: importance s=0.15\\n    result: median gradient 12.8x\\n  - exp_id: mvp_v5_fixed_s020_r2\\n    role: importance s=0.20\\n    result: median gradient 28.7x\\n  - exp_id: mvp_v5_fixed_s025\\n    role: importance s=0.25\\n    result: median gradient 52.9x\\n  - exp_id: mvp_v5_fixed_s030_r2\\n    role: importance s=0.30\\n    result: median gradient 74.9x\\n  - exp_id: mvp_v5_random_s015\\n    role: random baseline s=0.15\\n    result: gradient 1.14x\\n  - exp_id: mvp_v5_random_s025\\n    role: random baseline s=0.25\\n    result: gradient 0.97x\\n  depends_on:\\n  - D014\\n- id: D016\\n  date: 2026-05-14 03:00 UTC\\n  summary: 'D015: GO — Phase-modulated severity claim 验证通过，进入 M1'' bootstrap CI +\\n    cross-model'\\n  rationale: Importance median gradient 单调递增 12.8x→28.7x→52.9x→74.9x（4 sparsity levels），random\\n    baseline gradient ≈1x（phase-independent）。Importance/random gradient 比值 11.2x-54.5x，CI\\n    不重叠。核心 claim \\\"importance eviction 下 compound interaction 是 phase-dependent 的\\\"\\n    获实证支撑。叙事锚定 median（mean 因 heavy tail 膨胀，s030 mean/median=43:1）。附带发现：importance\\n    产生 phase-selective amplification（高 sparsity phase 反而减少交互，低 sparsity phase 大幅放大），强化\\n    phase-gated controller motivation。\\n  related_experiments:\\n  - exp_id: mvp_v5_fixed_s015\\n    role: importance s=0.15\\n    result: median gradient 12.8x\\n  - exp_id: mvp_v5_fixed_s020_r2\\n    role: importance s=0.20\\n    result: median gradient 28.7x\\n  - exp_id: mvp_v5_fixed_s025\\n    role: importance s=0.25\\n    result: median gradient 52.9x\\n  - exp_id: mvp_v5_fixed_s030_r2\\n    role: importance s=0.30\\n    result: median gradient 74.9x\\n  - exp_id: mvp_v5_random_s015\\n    role: random baseline s=0.15\\n    result: gradient 1.14x (phase-independent)\\n  - exp_id: mvp_v5_random_s025\\n    role: random baseline s=0.25\\n    result: gradient 0.97x (phase-independent)\\n  depends_on:\\n  - D014\\n- id: D017\\n  date: 2026-05-14 04:49 UTC\\n  summary: 'D017: Bootstrap CI confirms importance gradient 11-42× (all p=0.0000);\\n    launch cross-model + random re-run'\\n  rationale: v6 importance 四组 per-problem bootstrap (B=10000) 结果：paired gradient 11.5-41.9×,\\n    unpaired 12.7-39.3×, 所有 CI 下界远离 1.0, p=0.0000。Phase-modulated severity claim 统计显著成立。下一步：(1)\\n    Qwen2.5-7B cross-model 验证泛化性，(2) 用 v6 代码重跑 random 获取 per_problem_ii 做同粒度对比。论文主表用\\n    unpaired bootstrap（n 更大 CI 更窄），paired 放 appendix。4 GPU 并行：2 卡 Qwen importance\\n    + 2 卡 random re-run。\\n  related_experiments:\\n  - exp_id: v6_importance_s015\\n    role: primary\\n    result: gradient=11.53×, CI=[3.49,23.78]\\n  - exp_id: v6_importance_s020\\n    role: primary\\n    result: gradient=11.05×, CI=[5.42,69.27]\\n  - exp_id: v6_importance_s025\\n    role: primary\\n    result: gradient=35.72×, CI=[9.52,101.54]\\n  - exp_id: v6_importance_s030\\n    role: primary\\n    result: gradient=41.92×, CI=[19.14,299.76]\\n  depends_on:\\n  - D016\\n- id: D018\\n  date: 2026-05-14 05:24 UTC\\n  summary: Qwen 速度问题为误诊（实际 ~50s/problem），停止 Route B speed fix；NaN overlap 检查为 P0 阻塞项\\n  rationale: Reviewer 核实 Qwen 日志发现实际速度 ~50s/problem（与 DeepSeek 相当），之前 37-75min/problem\\n    的诊断错误。Kill Qwen 实验的决策基于错误前提。Route B worker 在解决不存在的问题，应停止。NaN overlap 检查决定是否需要\\n    bf16 全量重跑，是当前最高优先级阻塞项。\\n  related_experiments:\\n  - exp_id: qwen_importance_s015\\n    role: killed_误诊\\n    result: killed\\n  - exp_id: qwen_importance_s020\\n    role: killed_误诊\\n    result: killed\\n  - exp_id: qwen_importance_s025\\n    role: killed_误诊\\n    result: killed\\n  - exp_id: qwen_importance_s030\\n    role: killed_误诊\\n    result: killed\\n  depends_on:\\n  - D017\\n- id: D019\\n  date: 2026-05-14 05:31 UTC\\n  summary: bf16 全量重跑：NaN 过滤存在选择偏差（15.3% 不一致），fp16 结果不可用于论文 claim\\n  rationale: Reviewer 审查发现 s015 vs s030 中 23/150 对 null 状态不一致（ii_mid 不一致率 24%），NaN\\n    不仅来自 dense forward（Layer 27），还来自 sparse 条件本身。NaN 过滤会系统性丢弃 sparse 表现最差位置，导致 II\\n    估计偏低。bf16 5-problem 验证已通过（仅 1 个合法缺失）。当前 fp16 v6_random 让其跑完（sunk cost），但论文数据必须基于\\n    bf16 重跑版本。\\n  related_experiments:\\n  - exp_id: v6_importance_s015\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_importance_s020\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_importance_s025\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_importance_s030\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_random_s015\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_random_s020\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_random_s025\\n    role: affected\\n    result: fp16 NaN bias\\n  - exp_id: v6_random_s030\\n    role: affected\\n    result: killed + fp16 NaN bias\\n  depends_on: []\\n- id: D020\\n  date: 2026-05-14 05:35 UTC\\n  summary: bf16 全量重跑：16 个实验（DeepSeek + Qwen × importance + random × 4 sparsity），论文数据统一\\n    bf16\\n  rationale: fp16 NaN 跨条件不一致率 15.3%（NaN overlap 检查确认），null-filter 后存在选择偏差。bf16 验证\\n    0 NaN。fp16 vs bf16 数值精度不同导致 token 序列差异，不可混用。全量重跑 ~3h，时间充裕。\\n  related_experiments:\\n  - exp_id: v6_importance_s015\\n    role: affected\\n    result: fp16 NaN 需重跑\\n  - exp_id: v6_importance_s020\\n    role: affected\\n    result: fp16 NaN 需重跑\\n  - exp_id: v6_importance_s025\\n    role: affected\\n    result: fp16 NaN 需重跑\\n  - exp_id: v6_importance_s030\\n    role: affected\\n    result: fp16 NaN 需重跑\\n  - exp_id: bf16_verify\\n    role: evidence\\n    result: bf16 消除 NaN，0/50\\n  - exp_id: qwen_pilot\\n    role: evidence\\n    result: Qwen bf16 同样 NaN-free\\n  depends_on: []\\n- id: D021\\n  date: 2026-05-14 05:53 UTC\\n  summary: 'Framing constraint D023: super-additivity claim must specify phase-dependent\\n    gradient, not mere existence'\\n  rationale: 'Reviewer 审查 v6_random_s020 发现 random masking 也产生正 II（mean ~0.9-1.3×），因此论文不能\\n    claim \\\"importance masking produces super-additive interaction\\\"——random 也有。区分信号是\\n    phase-dependent gradient（importance: 跨两个数量级 vs random: ~1× flat）。同时 high_sparsity\\n    skewness=-4.83 要求 permutation test 使用 robust statistic。'\\n  related_experiments:\\n  - exp_id: v6_random_s020\\n    role: evidence\\n    result: random II positive (~0.9-1.3×) but no phase-dependent gradient — expected\\n      baseline behavior\\n  depends_on:\\n  - D015\\n- id: D022\\n  date: 2026-05-14 05:58 UTC\\n  summary: 'D024: Bootstrap B=1000→10000 修正 + Results 写作 CRITICAL 修复'\\n  rationale: Reviewer 发现论文声称 B=10,000 但实际 profiling config 为 n_bootstrap=1000，导致 p\\n    < 10^-4 claim 不成立（B=1000 最多 p < 0.001）。修正方案：(1) fp16 参考文本改为 B=1000 + p < 0.001；(2)\\n    bf16 重跑全部设 n_bootstrap=10000 以支持更强统计声明。同时修复 results.tex dtype 虚假声明、\\\\label 冲突、random\\n    \\\"negligible\\\" 违反 D023 等问题。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: config_update\\n    result: n_bootstrap→10000\\n  - exp_id: bf16_importance_s020\\n    role: config_update\\n    result: n_bootstrap→10000\\n  - exp_id: bf16_importance_s025\\n    role: config_update\\n    result: n_bootstrap→10000\\n  - exp_id: v6_importance_s020\\n    role: evidence\\n    result: actual B=1000 confirmed\\n  depends_on:\\n  - D020\\n  - D023\\n- id: D023\\n  date: 2026-05-14 06:00 UTC\\n  summary: Bootstrap B 值修正：fp16 实际 B=1000（非论文误写 10000），bf16 重跑设 n_bootstrap=10000\\n  rationale: Reviewer 审查发现 results_5_1.tex 声称 B=10000 但 profiling config 实际为 n_bootstrap=1000。直接后果：(1)\\n    p < 10^-4 声明不成立，B=1000 精度上限为 p < 0.001；(2) CI 宽度有差异。修正策略：fp16 参考数据如实标注 B=1000；bf16\\n    重跑批次将 n_bootstrap 设为 10000，最终论文基于 bf16 数据可合法声称 B=10000。同时修正 paper_framing.md RC4\\n    部分。\\n  related_experiments:\\n  - exp_id: v6_importance_s020\\n    role: evidence\\n    result: profiling config confirmed n_bootstrap=1000\\n  - exp_id: v6_importance_s030\\n    role: evidence\\n    result: profiling config confirmed n_bootstrap=1000\\n  - exp_id: bf16_importance_s015\\n    role: affected\\n    result: will use n_bootstrap=10000\\n  - exp_id: bf16_importance_s020\\n    role: affected\\n    result: will use n_bootstrap=10000\\n  - exp_id: bf16_importance_s025\\n    role: affected\\n    result: will use n_bootstrap=10000\\n  depends_on:\\n  - D020\\n  - D019\\n- id: D024\\n  date: 2026-05-14 06:01 UTC\\n  summary: Bootstrap B 值修正：fp16 实际 B=1000（论文误写 10000），bf16 重跑设 n_bootstrap=10000；统一\\n    results 文件消除 dtype 矛盾和 label 冲突\\n  rationale: 4 份 Reviewer 报告一致标记 CRITICAL：(1) profiling_results.json 确认 n_bootstrap=1000，论文声称\\n    B=10000 属数据报告错误，p < 10^-4 不成立（B=1000 上限 p < 0.001）；(2) results.tex 声称 bf16 但数据全为\\n    fp16；(3) 两文件 \\\\label 冲突。修正策略：bf16 重跑时设 n_bootstrap=10000 一劳永逸，final paper 用 bf16\\n    数据可合法声称 B=10000。results_5_1.tex 作为 fp16 参考存档，results.tex 为 canonical skeleton，统一\\n    label。\\n  related_experiments:\\n  - exp_id: v6_importance_s020\\n    role: evidence\\n    result: profiling config confirms n_bootstrap=1000\\n  - exp_id: v6_importance_s030\\n    role: evidence\\n    result: profiling config confirms n_bootstrap=1000\\n  - exp_id: bf16_importance_s015\\n    role: fix_target\\n    result: set n_bootstrap=10000\\n  - exp_id: bf16_importance_s020\\n    role: fix_target\\n    result: set n_bootstrap=10000\\n  - exp_id: bf16_importance_s025\\n    role: fix_target\\n    result: set n_bootstrap=10000\\n  depends_on:\\n  - D020\\n  - D019\\n- id: D025\\n  date: 2026-05-14 06:27 UTC\\n  summary: Claim 锚点从 sign reversal 转为 magnitude gradient——s=0.15 sign reversal 由 outlier\\n    驱动，不作为主证据\\n  rationale: Reviewer 审查 bf16_importance_s015 发现：high_sparsity mean=-0.150 但 median=+0.006，skewness=-14.99，仅\\n    2 个 outlier 拉负。winsorized mean 保留负号但幅度大幅缩小(-0.062)。\\\"magnitude gradient\\\"(low >\\n    mid > high)在 mean/median/winsorized mean 上均稳健，是更可靠的 claim 锚点。s=0.25 gradient=85.4x\\n    更强且无 sign reversal 争议。论文应以 magnitude gradient 为主证据，sign reversal 作为 mean-level\\n    次级观察并加 caveat。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: evidence\\n    result: sign reversal fragile at mean level; magnitude gradient robust\\n  depends_on: []\\n- id: D026\\n  date: 2026-05-14 06:27 UTC\\n  summary: 论文核心证据改用 CI non-overlap + 绝对 II 值，gradient ratio 降级为辅助描述\\n  rationale: 'Reviewer 审查发现：(1) gradient_paired_aggregate 因 high_sparsity II 近零（s015:\\n    0.00012, s025: 0.01）导致比值膨胀无统计意义；(2) 同一实验不同 gradient 计算方法得 16x vs 69x（s015）或 85x\\n    vs 222x（s025），审稿人必攻此不一致。决定：论文主体用三 phase 的 II 绝对值 + bootstrap CI 作为核心证据（CI non-overlap\\n    已通过验证），gradient ratio 仅作辅助描述性语言，不作为 headline number。等 s020 bf16 完成后做三点 dose-response\\n    分析替代单一 gradient 数字。同时 paper_framing.md 中 \\\"11-42×\\\" 数字需在 bf16 全部完成后统一更新为基于 CI 的表述。'\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: evidence\\n    result: gradient_paired_aggregate=69.24 vs gradient_low_over_abs_high=16.02, 4.3x差异\\n  - exp_id: bf16_importance_s025\\n    role: evidence\\n    result: gradient_paired_aggregate=222.35 vs gradient_low_over_high=85.4, 2.6x差异\\n  depends_on:\\n  - D015\\n  - D023\\n- id: D027\\n  date: 2026-05-14 06:41 UTC\\n  summary: 论文 high-phase II 统一用 median 报告，辅以 winsorized mean，注明 skewness\\n  rationale: bf16_importance_s020 的 high-phase skewness=16.67，2 个 outlier 把 raw mean\\n    从负拉到 +0.129（winsorized_mean=-0.030, median=0.015）。三个 sparsity level 的 high-phase\\n    均存在右偏。用 raw mean 报告会被审稿人攻击为 outlier-driven。统一用 median 反映 central tendency，winsorized\\n    mean 作为 robustness check，skewness 作为分布特征注明。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: evidence\\n    result: high-phase 同样右偏\\n  - exp_id: bf16_importance_s020\\n    role: trigger\\n    result: skewness=16.67, mean=+0.129 vs winsorized=-0.030\\n  - exp_id: bf16_importance_s025\\n    role: evidence\\n    result: high-phase 跨 sparsity 一致\\n  depends_on: []\\n- id: D028\\n  date: 2026-05-14 06:42 UTC\\n  summary: bf16 importance 全系列 4/4 完成，gradient ratio 47-104×，远超 fp16 的 11-42×；s=0.30\\n    高 phase CI>0 可作论文叙事亮点\\n  rationale: bf16 DeepSeek importance s015-s030 全部 PASS，phase gradient 方向跨 4 个 sparsity\\n    level 高度一致。低/高 phase ratio 从 47×(s020) 到 104×(s030) 单调递增，比 fp16 系列的 11-42× 显著更强——bf16\\n    消除了数值精度噪声后效应更清晰。s=0.30 是唯一高 phase CI 完全>0 的水平，说明 compound effect 在高 sparsity 下渗透到所有\\n    phase，可用于论文叙事。ROADMAP 数字待 bf16 random 对照组完成后统一更新。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: evidence\\n    result: PASS, low/high=69× (median)\\n  - exp_id: bf16_importance_s020\\n    role: evidence\\n    result: PASS, low/high=47×\\n  - exp_id: bf16_importance_s025\\n    role: evidence\\n    result: PASS, low/high=85×\\n  - exp_id: bf16_importance_s030\\n    role: evidence\\n    result: PASS, low/high=104×, high CI>0\\n  depends_on:\\n  - D027\\n- id: D029\\n  date: 2026-05-14 06:43 UTC\\n  summary: v6_random_s030 PASS 是 outlier artifact，permutation test mean→median 修复升为\\n    bf16 random 前置阻塞项\\n  rationale: Reviewer 审查确认：s030 random 的 Verdict=PASS 由单个 mid-phase extreme segment\\n    驱动（attn PPL=382.65，II mean=-230.76）。Median/winsorized mean 下三 phase 平坦（2.4-4.7），与\\n    s015/s020/s025 一致。Mean-based permutation test 在高 sparsity 完全不可靠。必须在 bf16 random\\n    batch 产出数据前修复 test statistic 为 median-based，否则 bf16 会复现假阳性。论文报告 random baseline\\n    统一用 median + winsorized mean。\\n  related_experiments:\\n  - exp_id: v6_random_s030_r3\\n    role: trigger\\n    result: PASS is outlier artifact\\n  - exp_id: v6_random_s015\\n    role: reference\\n    result: FAIL (expected)\\n  - exp_id: v6_random_s020\\n    role: reference\\n    result: FAIL (expected)\\n  - exp_id: v6_random_s025\\n    role: reference\\n    result: FAIL (expected)\\n  depends_on:\\n  - D027\\n- id: D030\\n  date: 2026-05-14 06:46 UTC\\n  summary: Random baseline mean-based II outlier 确认为系统性问题，论文须说明 II heavy-tail 特性及\\n    median 选择理由\\n  rationale: bf16_ds_rand_s015 复现了 v6_random_s030_r3 的完全一致模式：mid-phase 个别 segment\\n    random 移除命中关键 attention head → attn PPL 爆炸 → II mean 被 1-2 个 outlier 主导（mean=-172.66\\n    vs median=0.097）。两个独立实验（不同 sparsity、不同精度）出现同样问题，确认系统性。预计 bf16_ds_rand_s020/s025\\n    也会出现。论文 methodology 必须明确说明 II 的 heavy-tail 特性 + 为什么使用 median（审稿人看到 mean/median\\n    差异 1000× 必问）。Median 数据本身质量正常，fp16/bf16 量级一致。\\n  related_experiments:\\n  - exp_id: bf16_ds_rand_s015\\n    role: trigger\\n    result: mean outlier confirmed systemic\\n  - exp_id: v6_random_s030_r3\\n    role: reference\\n    result: first instance of same pattern\\n  depends_on:\\n  - D029\\n- id: D031\\n  date: 2026-05-14 06:52 UTC\\n  summary: bf16 DeepSeek importance 全系列 4/4 PASS，论文 gradient 报告统一用差值 (II_low - II_high)\\n    替代 ratio\\n  rationale: bf16 importance s015/s020/s025/s030 全部 verdict=PASS，phase gradient (low>>mid>>high)\\n    在所有 sparsity level 稳定成立，跨 sparsity 单调递增，low vs mid CI 不重叠。Median-based ratio gradient（66-276×）因\\n    high_median 极小（0.006-0.053）而不稳定，审稿人会质疑近零除法。决定论文和 ROADMAP 统一用差值 (median_low - median_high)\\n    报告 gradient，避免 ratio metric 的分母近零问题。差值：s015=0.39, s020=1.49, s025=7.17, s030=14.59——清晰的单调递增趋势，不受除零影响。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: evidence\\n    result: PASS, low_median=0.40\\n  - exp_id: bf16_importance_s020\\n    role: evidence\\n    result: PASS, low_median=1.50\\n  - exp_id: bf16_importance_s025\\n    role: evidence\\n    result: PASS, low_median=7.20\\n  - exp_id: bf16_importance_s030\\n    role: evidence\\n    result: PASS, low_median=14.64\\n  depends_on:\\n  - D029\\n  - D030\\n- id: D032\\n  date: 2026-05-14 07:28 UTC\\n  summary: 论文主统计检验改用 difference statistic（ii_low − ii_high），ratio 降为 appendix 辅助\\n  rationale: Permutation test 全 4 水平结果：difference statistic 全部 Bonferroni 校正后 p<0.005，效应量单调递增（0.35→1.14→4.02→9.95）。Ratio\\n    statistic 受 EPS=0.01 过滤影响，低 sparsity 水平 n_paired 从 49 降至 32-41，s015/s020/s025\\n    不显著。Difference 对重尾分布更 robust，不受 EPS 过滤影响，且展示出清晰的 sparsity-severity 单调递增关系——解决了\\n    C2 之前的非单调性问题。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: importance_baseline\\n    result: PASS\\n  - exp_id: bf16_importance_s020\\n    role: importance_baseline\\n    result: PASS\\n  - exp_id: bf16_importance_s025\\n    role: importance_baseline\\n    result: PASS\\n  - exp_id: bf16_importance_s030\\n    role: importance_baseline\\n    result: PASS\\n  - exp_id: bf16_ds_rand_s015\\n    role: random_control\\n    result: verdict_pending\\n  - exp_id: bf16_ds_rand_s020\\n    role: random_control\\n    result: verdict_pending\\n  - exp_id: bf16_ds_rand_s025\\n    role: random_control\\n    result: verdict_pending\\n  - exp_id: bf16_ds_rand_s030\\n    role: random_control\\n    result: verdict_pending\\n  depends_on:\\n  - D028\\n  - D030\\n- id: D033\\n  date: 2026-05-14 07:45 UTC\\n  summary: 弃用所有 ratio 指标，论文主指标改为 median difference + Cohen's d；registry gradient_paired_aggregate\\n    字段定义不一致已确认\\n  rationale: 溯源调查发现 registry 中 gradient_paired_aggregate 字段计算方式跨 sparsity 不一致（s015/s025\\n    用 median ratio，s020/s030 用 mean difference），导致 \\\"47-104×\\\" 不可溯源。根因：ratio 在 high-phase\\n    II 接近 0 时不稳定（29-49% 样本 < EPS=0.01）。替代方案 median difference 单调递增（0.39→1.48→7.16→14.59），Cohen's\\n    d 同样单调（0.60→0.72→0.95→1.12），与 D032 permutation test difference statistic 一致。论文全面弃用\\n    ratio 类指标。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: source_data\\n    result: gradient_paired_aggregate=69.24 (median ratio)\\n  - exp_id: bf16_importance_s020\\n    role: source_data\\n    result: gradient_paired_aggregate=5.90 (mean difference, mislabeled)\\n  - exp_id: bf16_importance_s025\\n    role: source_data\\n    result: gradient_paired_aggregate=222.35 (median ratio, inflated by small denominator)\\n  - exp_id: bf16_importance_s030\\n    role: source_data\\n    result: gradient_paired_aggregate=57.24 (mean difference, mislabeled)\\n  depends_on:\\n  - D032\\n  - D028\\n- id: D034\\n  date: 2026-05-14 07:55 UTC\\n  summary: 'C5 cross-model replication confirmed: Qwen2.5-7B-Instruct bf16 importance\\n    4/4 PASS，median difference 单调递增 0.039→2.943'\\n  rationale: Qwen bf16 importance 全 4 水平 PASS，median difference 单调递增（0.039→0.235→1.268→2.943），与\\n    DeepSeek 模式一致（0.39→14.59），magnitude 约为 DeepSeek 1/5。CI non-overlap 在所有 4 个 sparsity\\n    level 成立。跨模型方向一致性强，C5 claim 可以成立。\\n  related_experiments:\\n  - exp_id: bf16_qw_imp_s015\\n    role: cross_model_replication\\n    result: PASS, diff=0.039\\n  - exp_id: bf16_qw_imp_s020\\n    role: cross_model_replication\\n    result: PASS, diff=0.235\\n  - exp_id: bf16_qw_imp_s025\\n    role: cross_model_replication\\n    result: PASS, diff=1.268\\n  - exp_id: bf16_qw_imp_s030\\n    role: cross_model_replication\\n    result: PASS, diff=2.943\\n  depends_on:\\n  - D032\\n  - D033\\n- id: D035\\n  date: 2026-05-14 08:01 UTC\\n  summary: Cohen's d 修正：实际值 0.44→0.80（旧 claim 0.60→1.12 偏高 25-30%），单调递增趋势不变，叙事改为\\\"small→large\\n    effect size gradient\\\"\\n  rationale: Agent 用 paired Cohen's d (n=49, B=10000 bootstrap CI) 重新计算，发现 D033 中的数字无实际计算来源。实际\\n    s015=0.44(small), s020=0.52(medium), s025=0.68(medium), s030=0.80(large)。趋势正确但绝对值需修正。论文必须引用实际计算值。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: source\\n    result: d=0.44\\n  - exp_id: bf16_importance_s020\\n    role: source\\n    result: d=0.52\\n  - exp_id: bf16_importance_s025\\n    role: source\\n    result: d=0.68\\n  - exp_id: bf16_importance_s030\\n    role: source\\n    result: d=0.80\\n  depends_on:\\n  - D033\\n- id: D036\\n  date: 2026-05-14 08:02 UTC\\n  summary: Cohen's d 修正：实际 0.44→0.52→0.68→0.80（D033 声称 0.60→1.12 高估 35-45%），单调递增趋势不变，论文引用新值\\n  rationale: Agent 用 paired Cohen's d_z + bootstrap CI(B=10000) 重新计算，Reviewer 审查 PASS。D033\\n    原值无计算来源。新值全部 CI 下界>0（显著），small→large 效应量递增与 sparsity-severity 叙事一致。论文需引用 cohens_d_bf16.json\\n    中的实际数值。\\n  related_experiments:\\n  - exp_id: bf16_importance_s015\\n    role: source\\n    result: d=0.44 [0.35,0.78]\\n  - exp_id: bf16_importance_s020\\n    role: source\\n    result: d=0.52 [0.43,0.90]\\n  - exp_id: bf16_importance_s025\\n    role: source\\n    result: d=0.68 [0.56,0.86]\\n  - exp_id: bf16_importance_s030\\n    role: source\\n    result: d=0.80 [0.67,1.02]\\n  depends_on:\\n  - D033\\n- id: D037\\n  date: 2026-05-14 08:05 UTC\\n  summary: 'Qwen Cohen''s d: 0.28→1.02 单调递增，但 s015 CI 含 0 不显著。叙事调整为 threshold 差异化——Qwen\\n    s≥0.20, DeepSeek s≥0.15'\\n  rationale: Reviewer 审查确认 Qwen s015 d=0.28 CI=[-0.006, 0.60] 在 95% 水平不显著。s020-s030\\n    全部显著且单调递增(0.55→0.89→1.02)。Qwen 高端效应量反超 DeepSeek(0.89/1.02 vs 0.68/0.80)因方差更低。叙事改为\\n    threshold 差异化表述，比统一 claim 更精确更 robust。n_skipped=4(8%) 需论文注明。\\n  related_experiments:\\n  - exp_id: bf16_qw_imp_s015\\n    role: source\\n    result: d=0.28 CI含0 不显著\\n  - exp_id: bf16_qw_imp_s020\\n    role: source\\n    result: d=0.55 显著\\n  - exp_id: bf16_qw_imp_s025\\n    role: source\\n    result: d=0.89 显著\\n  - exp_id: bf16_qw_imp_s030\\n    role: source\\n    result: d=1.02 显著\\n  depends_on:\\n  - D035\\n  - D034\\n- id: D038\\n  date: 2026-05-14 08:06 UTC\\n  summary: 'Qwen Cohen''s d: 0.28→1.02，s015 不显著(CI含0)。论文 dose-response claim 改为 \\\"s≥0.20\\n    for Qwen, s≥0.15 for DeepSeek\\\"，s015 行加注'\\n  rationale: Qwen s015 d=0.28 CI=[-0.006,0.60] 不显著；s020-s030 全显著且效应量反超 DeepSeek(s025:0.89vs0.68,\\n    s030:1.02vs0.80)。处理策略：(1) cross-model 表 s015 行注明 Qwen 不显著；(2) 叙事用 model-specific\\n    threshold 角度：compound interaction onset threshold 因模型而异，DeepSeek s≥0.15 即可观测，Qwen\\n    需 s≥0.20；(3) 这反而支持一个更细致的 claim——threshold 差异可能与模型的 attention head redundancy 有关。n_skipped=4(8%)\\n    需注明有效样本量。\\n  related_experiments:\\n  - exp_id: bf16_qw_imp_s015\\n    role: source\\n    result: d=0.28 non-significant\\n  - exp_id: bf16_qw_imp_s020\\n    role: source\\n    result: d=0.55\\n  - exp_id: bf16_qw_imp_s025\\n    role: source\\n    result: d=0.89\\n  - exp_id: bf16_qw_imp_s030\\n    role: source\\n    result: d=1.02\\n  depends_on:\\n  - D035\\n  - D034\\n- id: D039\\n  date: 2026-05-14 08:32 UTC\\n  summary: n_bootstrap=1000 处理策略：优先尝试从原始数据 re-bootstrap B=10000，否则论文如实标注 B=1,000\\n  rationale: 'D023 决定 bf16 实验用 B=10000，但实际所有 bf16 profiling 均为 B=1000。Cohen''s d 已用\\n    B=10000 不受影响。PASS/FAIL 判定在 B=1000 下有效。最优方案：检查 profiling_results.json 是否保存了 raw\\n    per-sample II 值，若有则用脚本 re-bootstrap B=10000（分钟级完成，不需重跑实验）；若无原始数据则论文如实标注 profiling\\n    CI: B=1,000 (p<0.001), Cohen''s d CI: B=10,000。'\\n  related_experiments:\\n  - exp_id: bf16_ds_imp_s015\\n    role: affected\\n    result: B=1000\\n  - exp_id: bf16_ds_imp_s030\\n    role: affected\\n    result: B=1000\\n  - exp_id: bf16_qw_imp_s015\\n    role: affected\\n    result: B=1000\\n  - exp_id: bf16_qw_imp_s020\\n    role: affected\\n    result: B=1000\\n  depends_on:\\n  - D023\\n  - D024\\n- id: D040\\n  date: 2026-05-14 08:32 UTC\\n  summary: Qwen random gradient 论文表述修正：不可声称 \\\"no phase gradient\\\"，应表述为统计不显著\\n  rationale: Qwen random 三组实验 gradient 均非零（0.050/0.129/0.660），s015 甚至 random > importance（0.050\\n    vs 0.039）。与 DeepSeek random 的清晰分离（13-39×）不同，Qwen 分离度仅 0.8-1.9×。CI overlap test\\n    正确判定 FAIL，结论有效。但论文 §5 需讨论：(1) 低 sparsity 下两种方法的 phase 效应均弱且不可区分；(2) 正确表述为 \\\"random\\n    gradient 不具统计显著性\\\" 而非 \\\"random 无 gradient\\\"。\\n  related_experiments:\\n  - exp_id: bf16_qw_rand_s015\\n    role: evidence\\n    result: FAIL, gradient=0.050\\n  - exp_id: bf16_qw_rand_s020\\n    role: evidence\\n    result: FAIL, gradient=0.129\\n  - exp_id: bf16_qw_rand_s025\\n    role: evidence\\n    result: FAIL, gradient=0.660\\n  - exp_id: bf16_qw_imp_s015\\n    role: comparison\\n    result: gradient=0.039, Cohen's d=0.28\\n  depends_on:\\n  - D037\\n  - D038\\n- id: D041\\n  date: 2026-05-14 08:45 UTC\\n  summary: 'CRITICAL: Qwen random s030 PASS (gradient 4.241 > importance 2.943)——borderline，立即\\n    B=10000 re-bootstrap 验证'\\n  rationale: bf16_qw_rand_s030 CI overlap test PASS，random gradient (4.241) > importance\\n    gradient (2.943)。但 CI gap 仅 0.161（极 borderline），且 n_bootstrap=1000（D023 要求 10000）。B=10000\\n    的更窄 CI 可能翻转为 FAIL。DeepSeek random s030 gradient=1.538 仍 FAIL（importance/random\\n    分离>10×），问题仅限 Qwen s030。两种应对路径：(1) B=10000 re-bootstrap 后 FAIL → 维持原叙事，注明 B=1000\\n    时 borderline；(2) B=10000 后仍 PASS → 论文叙事调整为\\\"moderate sparsity 下 importance 特有，extreme\\n    sparsity 下两策略收敛\\\"，与 entropy-discrimination collapse 机制一致（极高 sparsity 下 head pruning\\n    损伤压倒策略差异）。\\n  related_experiments:\\n  - exp_id: bf16_qw_rand_s030\\n    role: trigger\\n    result: PASS, gradient=4.241\\n  - exp_id: bf16_qw_imp_s030\\n    role: comparison\\n    result: PASS, gradient=2.943\\n  - exp_id: bf16_ds_rand_s030\\n    role: cross-model\\n    result: FAIL, gradient=1.538\\n  depends_on:\\n  - D034\\n  - D039\\n  - D040\\n- id: D042\\n  date: 2026-05-14 08:53 UTC\\n  summary: D041 更新：Qwen random s030 B=10000 后 Cohen's d≈0，aggregate PASS 但无 within-problem\\n    consistency，critical 降级 warning\\n  rationale: B=10000 re-bootstrap 后：(1) median_diff 从 4.241 降至 2.418，现在小于 importance\\n    的 2.943；(2) Cohen's d = -0.035（importance 为 1.02），说明 random 的 aggregate gradient\\n    来自 between-problem variability 而非 within-problem phase effect；(3) permutation\\n    p=0.012，Bonferroni 校正后 borderline（阈值 0.0125）。论文叙事策略：主用 Cohen's d 作为 importance\\n    vs random 的判别指标（1.02 vs ~0，无争议），承认 Qwen s030 aggregate median 有弱趋势但无 within-problem\\n    consistency，与 entropy-discrimination collapse 机制一致——extreme sparsity 下 between-problem\\n    variability 增大但不形成系统性 phase effect。\\n  related_experiments:\\n  - exp_id: bf16_qw_rand_s030\\n    role: trigger\\n    result: PASS verdict retained, but Cohen's d=-0.035, median_diff=2.418\\n  - exp_id: bf16_qw_imp_s030\\n    role: comparison\\n    result: Cohen's d=1.02, gradient=2.943\\n  depends_on:\\n  - D041\\n  - D040\\n  - D038\\n- id: D043\\n  date: 2026-05-14 08:59 UTC\\n  summary: D041 结论：B=10000 re-bootstrap 后 bf16_qw_rand_s030 仍 PASS (gradient 2.418)，但\\n    Cohen's d≈0——效应量可忽略，叙事可防御\\n  rationale: B=10000 re-bootstrap 将 gradient 从 4.241 降至 2.418（CI 收窄），verdict 仍 PASS。但\\n    Cohen's d ≈ 0 表明无实际意义的效应量。对比 Qwen importance s030 Cohen's d=1.02，两者差异巨大。论文叙事策略：(1)\\n    Table 中标注 QW random s030 为 \\\"borderline PASS, d≈0\\\"；(2) §5 讨论：CI test 敏感到 borderline\\n    显著但效应量可忽略；(3) 与 importance 的 dose-response gradient（d=0.28→1.02）形成对比——random 即使\\n    borderline PASS 也无 dose-response 模式。DeepSeek random 全 4 水平均 FAIL，问题仅限 Qwen s030\\n    单个数据点。\\n  related_experiments:\\n  - exp_id: bf16_qw_rand_s030\\n    role: trigger\\n    result: PASS, gradient=2.418, Cohen's d≈0\\n  - exp_id: bf16_qw_imp_s030\\n    role: comparison\\n    result: PASS, gradient=2.943, Cohen's d=1.02\\n  depends_on:\\n  - D041\\n- id: D044\\n  date: 2026-05-14 09:10 UTC\\n  summary: 'C4 entropy-discrimination collapse: Qwen s025 符号反转需调查，论文需 cross-model\\n    caveat。Gini 效应 model-dependent（Qwen 1/3~1/4 of DeepSeek）。C4 维持 partially_confirmed\\n    直到 per-problem 分析完成。'\\n  rationale: Reviewer 审查 qwen_c4_entropy 结果发现：(1) Entropy Δ 6/8 configurations 方向一致但\\n    Qwen s025 有符号反转 (+0.0451 vs DeepSeek -0.0446)；(2) Gini 效应 Qwen 远弱于 DeepSeek。不杀\\n    C4 但需要 honest reporting + per-problem 分析确认是否 outlier-driven。\\n  related_experiments:\\n  - exp_id: qwen_c4_entropy\\n    role: evidence\\n    result: anomaly at s025\\n  - exp_id: c4_attention_entropy\\n    role: baseline\\n    result: DeepSeek all negative\\n  depends_on:\\n  - D032\\n  - D034\\n- id: D045\\n  date: 2026-05-14 09:17 UTC\\n  summary: C4 从 Core Claim 降为 §6 supporting analysis（方案 A）；采用 per-problem paired Cohen's\\n    d 作为论文主统计量\\n  rationale: qwen_c4_entropy 30/30 完成后结论 negative：entropy-discrimination collapse\\n    在 DeepSeek 成立但 Qwen 不复现（s025 符号反转）。论文核心 story 是 phenomenon（phase-dependent severity\\n    gradient，C1-C3/C5/C6 全 confirmed），不依赖 mechanism claim。降级 C4 最 defensible，避免 overclaim\\n    被审稿人攻击。Cohen's d 采用 per-problem paired 因为实验是 within-subjects 配对设计，segment-level\\n    aggregate 放 supplementary 作 robustness check。\\n  related_experiments:\\n  - exp_id: qwen_c4_entropy\\n    role: trigger\\n    result: negative — Qwen entropy proxy 不复现 DeepSeek 的 discrimination collapse\\n  - exp_id: c4_attention_entropy\\n    role: reference\\n    result: DeepSeek entropy collapse confirmed\\n  - exp_id: bf16_importance_s015\\n    role: reference\\n    result: B=10000 re-bootstrap completed\\n  - exp_id: bf16_importance_s030\\n    role: reference\\n    result: B=10000 re-bootstrap completed\\n  depends_on:\\n  - D044\\n  - D039\\n- id: D046\\n  date: 2026-05-14 09:19 UTC\\n  summary: 'C4 entropy-collapse 从 Core Claim 降为 §6 supporting analysis（方案 A: model-dependent\\n    mechanism）'\\n  rationale: Qwen s025 entropy delta 反转(+0.045)、s030 近零，跨模型一致性不成立。但 DeepSeek 四水平一致，且\\n    Qwen mid-phase 仅 26 segments 统计功效不足可能是 confound。选方案 A：保留 §6 分析但诚实报告两模型差异，不再作为跨模型通用\\n    mechanism claim。核心 empirical claims C1-C3/C5/C6 不受影响。若 s025 调查确认是方差 artifact 可回升强度。\\n  related_experiments:\\n  - exp_id: qwen_c4_entropy\\n    role: primary\\n    result: 'C4 cross-model inconsistent: DeepSeek consistent, Qwen partial (s015/s020\\n      ok, s025 reversed, s030 near-zero)'\\n  - exp_id: worker_analysis_qwen_s025_entropy_investigation\\n    role: followup\\n    result: completed, pending Agent processing\\n  depends_on: []\\n- id: D047\\n  date: 2026-05-14 09:38 UTC\\n  summary: 纳入 6-point dose-response 数据（s=0.10~0.35），限定 II_high<0.06 claim 至 s≤0.30\\n  rationale: 6-point 单调性 Spearman ρ=1.0 显著加固 C2+C5。Qwen s=0.10 sub-additive 现象揭示 onset\\n    threshold，增加科学深度。DS s=0.35 II_high=0.105 打破原 \\\"<0.06\\\" claim，需限定范围。收益（更强证据链）远大于成本（限定一个\\n    claim + 加一段 onset 讨论）。\\n  related_experiments:\\n  - exp_id: bf16_ds_imp_s010\\n    role: extension\\n    result: near-zero II, monotonicity anchor\\n  - exp_id: bf16_ds_imp_s035\\n    role: extension\\n    result: II_high=0.105, ceiling effect\\n  - exp_id: bf16_qw_imp_s010\\n    role: extension\\n    result: sub-additive II, onset threshold\\n  - exp_id: bf16_qw_imp_s035\\n    role: extension\\n    result: monotonicity confirmed\\n  depends_on: []\\n- id: D048\\n  date: 2026-05-14 09:41 UTC\\n  summary: 统一使用 paired d_z (cohens_d_bf16.json) 替换论文全文 independent-samples d\\n  rationale: Reviewer CRITICAL：配对数据（同一 problem 的 low/high phase）必须用 paired d_z = mean(diffs)/std(diffs)，论文错误使用了\\n    rebootstrap 的 independent-samples d，效应量系统性膨胀 20-40%。Table 4 caption 描述与实际计算不匹配。采用方案\\n    A：直接用 cohens_d_bf16.json 已有的 paired d_z 值，修改论文 6 处。主要结论不变。\\n  related_experiments: []\\n  depends_on: []\\n- id: D049\\n  date: 2026-05-14 09:55 UTC\\n  summary: Table 4 bootstrap CI caption 澄清：改 caption 措辞而非重算 CI\\n  rationale: Reviewer 发现 Table 4 bootstrap CI 使用 independent resampling 但 caption\\n    写 \\\"per-problem paired\\\"。unpaired bootstrap 产生更宽（更保守）的 CI，所有结论方向不变。选择方案 (b)：caption\\n    明确 CI 为 independent bootstrap of medians，避免重新计算的成本。优先级低于编译冲刺，编译通过后处理。\\n  related_experiments: []\\n  depends_on:\\n  - D048\\n- id: D050\\n  date: 2026-05-14 10:03 UTC\\n  summary: 回退 fix-cohens-d-notation Worker 的全部修改，恢复 D048 正确的 paired d_z 值\\n  rationale: Worker 被文件名 cohens_d_paired_b10000.json 中的 \\\"paired\\\" 误导，实际该文件使用 pooled-SD\\n    independent-samples d 公式。正确数据源是 cohens_d_bf16.json（compute_cohens_d.py 使用 mean(diffs)/std(diffs,ddof=1)\\n    = paired d_z）。符号统一用 \\\"Cohen's d\\\" 而非 d_z。\\n  related_experiments: []\\n  depends_on:\\n  - D048\\n- id: D051\\n  date: 2026-05-14 10:04 UTC\\n  summary: 图表全部基于过时数据，需用 bf16 canonical 数据重新生成；删除硬编码脚本 generate_all_figures.py\\n  rationale: Reviewer 发现：(1) generate_all_figures.py 硬编码数据与任何分析文件不匹配（G_imp 差数量级），Cohen's\\n    d 使用弃用的 independent-samples d；(2) generate_paper_figures.py 读取 v5 旧数据（bootstrap_results_full.json\\n    / v6_analysis_results.json），不是 bf16 canonical 数据；(3) figures/ 和 paper_figures/\\n    两个目录文件不一致。修复：删除硬编码脚本，用 bf16 profiling_output_bf16_* 数据重新生成所有分析 JSON 和图表，统一输出到\\n    paper_figures/。\\n  related_experiments: []\\n  depends_on:\\n  - D048\\n  - D050\\n- id: D052\\n  date: 2026-05-14 13:30 UTC\\n  summary: 采纳 Reviewer 审查：C5 pilot-first + heuristic baseline，C2 预注册 s015 ns 叙事，C9\\n    仅加引用\\n  rationale: Reviewer 独立审查 Round 1 应对方案后建议：(1) C5 先用 1-2 个 sparsity level 做 2h pilot，oracle\\n    回收 >30% compound degradation 才全面铺开，否则降为 future work；(2) C5 必须加 simple heuristic\\n    baseline（token position ratio 或 cumulative attention entropy 作 phase proxy），与\\n    oracle 构成上下界；(3) compute-matched 硬约束；(4) C2 n=500 前预定义\\\"若 s015 仍 ns 则叙事改为 compound\\n    effect emerges above threshold\\\"；(5) C9 Lethe 仅 Related Work 加一句区分引用，另加 SparK；(6)\\n    S3/S7 考虑升级为 C 级；(7) 预留 1 天写 rebuttal letter。\\n  related_experiments: []\\n  depends_on: []\\n- id: D053\\n  date: 2026-05-14 14:59 UTC\\n  summary: c5b_pilot s_trans cap 澄清：cap 作用于 s_trans 本身（≤0.50），不是 δ'\\n  rationale: Reviewer warning 发现 §3.2 公式（δ' cap=0.50）与 handoff checklist（s_trans capped\\n    at 0.50）存在歧义。选择解读 B（s_trans ≤ 0.50）：pilot 目的是检测 phase-aware KV modulation 信号存在性，s_trans=0.50\\n    已是 substantial modulation；80% KV eviction（解读 A 在 s=0.30 时）可能导致 forward pass 退化，污染后续\\n    phase 的 II 计算，引入混淆变量。信号存在后可在 follow-up 中升级探测范围。\\n  related_experiments:\\n  - exp_id: c5b_pilot\\n    role: target\\n    result: pending\\n  depends_on:\\n  - D052\\n- id: D054\\n  date: 2026-05-14 18:11 UTC\\n  summary: II 主指标从 mean 切换为 median + median bootstrap CI\\n  rationale: n=500 实验揭示 mean 被极端 outlier 摧毁（rand s015 mean 从 -1.9 暴跌到 -185K，而 median\\n    稳定 0.103→0.118）。imp 和 rand 的 outlier 方向相反，mean 虚假放大了效应量。Median 稳定、CI 收窄符合预期，作为\\n    heavy-tailed 分布的 robust central tendency 指标。\\n  related_experiments:\\n  - exp_id: c2_n500_deepseek\\n    role: trigger\\n    result: rand s015 mean=-185K, median=0.118\\n  - exp_id: c1_mvp\\n    role: affected\\n    result: mean 值需重新评估\\n  - exp_id: c3_llama\\n    role: affected\\n    result: mean 值需重新评估\\n  depends_on: []\\n- id: D055\\n  date: 2026-05-14 18:41 UTC\\n  summary: 'c5b_pilot conditional retry: CPU 诊断 root cause → 可修则 c2_n500 GPU 释放后 2h\\n    time-box 重试 → 仍失败或不可修则降为 future work'\\n  rationale: c5b 5×进程死亡是技术故障非假设否定。论文是 empirical finding paper，mitigation 非核心 claim，framing\\n    已有 future work fallback。距截稿 11 天，核心 claims 已 confirmed，诊断无 GPU 成本，若可修则 2h retry\\n    有正 EV（加强 RC3 应对）；若不可修则干净收尾。\\n  related_experiments:\\n  - exp_id: c5b_pilot\\n    role: subject\\n    result: failed 5×\\n  depends_on:\\n  - D052\\n- id: D056\\n  date: 2026-05-14 18:46 UTC\\n  summary: 撤回 D055，确认 c5b_pilot gate_failed（非技术故障）：oracle recovery 18% < 30% gate，C5b\\n    按 D052 预注册协议降为 future work\\n  rationale: D055 基于 Agent 汇报的\\\"5×进程死亡\\\"做出 conditional retry 决策，但 Reviewer 核实发现 PID\\n    154645 已正常完成 30/30 problems，结果文件存在(51KB)，gate_pass=false 是科学判定（oracle recovery\\n    18% < 30%）非技术故障。D052 预注册协议明确\\\"不达标→future work\\\"，D055 绕过了此协议。Heuristic recovery 32%\\n    > oracle 18% 的反直觉结果 + 两者 CI 均跨零，进一步确认当前 phase-aware allocation 信号不够强。论文 §6 Discussion\\n    可提及 pilot 结果（Wilcoxon 显著但效应量不足，方向正确需更精细方法）。\\n  related_experiments:\\n  - exp_id: c5b_pilot\\n    role: subject\\n    result: 'gate_failed: oracle recovery 18% < 30% threshold'\\n  depends_on:\\n  - D052\\n  - D055\\n- id: D057\\n  date: 2026-05-14 18:46 UTC\\n  summary: 修正 D055：c5b_pilot 实际已完成(gate_pass=false)，不需要 retry。Registry 改 gate_failed，c5b\\n    降为 future work grounding evidence\\n  rationale: Reviewer 发现 c5b_pilot PID 154645 于 02:37 UTC 正常完成 30/30 problems，非进程死亡。Oracle\\n    recovery 18% < 30% gate，heuristic 32% 但 CI 跨零（统计上不可区分零）。结论：naive phase-aware allocation\\n    信号存在（Wilcoxon p=0.002/0.024）但效应量不足，需更精细策略。作为 future work grounding evidence 写入论文\\n    §6 Discussion。\\n  related_experiments:\\n  - exp_id: c5b_pilot\\n    role: subject\\n    result: gate_failed (oracle 18% < 30% gate, heuristic 32% but CI crosses zero)\\n  depends_on:\\n  - D055\\n  - D052\\n- id: D058\\n  date: 2026-05-14 18:47 UTC\\n  summary: Qwen imp-vs-rand paired 对比 n=50 全部不显著：等 n=500 结果定论，预备 model-dependent magnitude\\n    叙事调整\\n  rationale: Reviewer 发现 Qwen 在 n=50 下 importance vs random 的 phase gradient paired\\n    对比全 4 水平不显著(p>0.07)，DeepSeek 全部高度显著(p≤0.0001)。n=50 对 Qwen 小效应量(d_z 0.09-0.16)功效不足，n=500\\n    是预设的功效提升实验。若 n=500 仍不显著，叙事调整为 \\\"effect magnitude is model-dependent, models with\\n    stronger importance discrimination show clearer phase-strategy differentiation\\\"——与\\n    discrimination collapse 机制一致(Qwen importance score 判别力本身较弱)。同时 Qwen mid-phase\\n    58% null rate 须在论文中披露 per-phase effective sample sizes。\\n  related_experiments:\\n  - exp_id: c2_qw_n500\\n    role: pending_verification\\n    result: running\\n  - exp_id: c2_n500_deepseek\\n    role: pending_verification\\n    result: running\\n  depends_on: []\\n- id: D059\\n  date: 2026-05-14 18:48 UTC\\n  summary: d_z 分场景报告：within-importance 保留 d_z，涉及 random 的比较只报 Wilcoxon p + median_diff，不报\\n    d_z（outlier 污染）\\n  rationale: Random pruning 14.2% catastrophic failure rate（ppl 爆炸至 236K，II min=-4.3M）导致\\n    mean-based d_z 不可靠。Within-importance 比较（C2 主结果）两边均为 importance 条件，无此问题，d_z 稳定。分场景处理既保持统计严谨性，又避免\\n    deadline 前大规模替换效应量指标。论文加脚注解释 random 不报 d_z 的原因（catastrophic ppl explosion in ~14%\\n    of random trials makes mean-based effect size unreliable）。\\n  related_experiments:\\n  - exp_id: c2_n500_deepseek\\n    role: context\\n    result: running — n=500 rand s015 outlier rate 14.2%\\n  depends_on:\\n  - D054\\n- id: D060\\n  date: 2026-05-14 18:52 UTC\\n  summary: C8 从 confirmed 降级为 partially_confirmed（qualitative direction consistent,\\n    quantitative interaction weaker）：LLaMA random 也显示 phase gradient，strategy-dependence\\n    弱于 DeepSeek/Qwen\\n  rationale: Reviewer 独立核实 c3_llama_results.json 发现：(1) within-importance phase gradient\\n    强且稳定（d_z~1.0）✓ (2) 但 imp_vs_rand 交互效应弱（d_z 0.19→0.34，仅 s030 Bonferroni 显著）(3)\\n    random eviction 在 LLaMA 上也显示非平凡 phase gradient（d_z 0.35→0.44, CI 排除零），与 DeepSeek/Qwen\\n    random 7/8 FAIL 模式定性不同。C8 支持 qualitative replication（importance phase gradient\\n    方向一致），但 strategy × phase interaction 的量化强度是 architecture-dependent。论文引用 LLaMA\\n    数据时必须加限定语，否则审稿人会攻击。\\n  related_experiments:\\n  - exp_id: c3_llama\\n    role: subject\\n    result: success but imp_vs_rand interaction weaker than DeepSeek/Qwen; random\\n      also shows phase gradient on LLaMA\\n  depends_on:\\n  - D056\\n- id: D061\\n  date: 2026-05-14 19:27 UTC\\n  summary: D058 已解决：n=500 下 DeepSeek 和 Qwen 的 paired gradient 均达 Bonferroni 显著\\n  rationale: s015 分析结果：DeepSeek median_D=-0.4227 p<0.0001 null_rate=10.2%；Qwen median_D=-0.0991\\n    p<0.0001 null_rate=45.2%。n=50 时 Qwen 功效不足的问题在 n=500 下完全解决。Qwen null rate 仍高(45.2%)，论文须披露\\n    per-phase effective sample size。\\n  related_experiments:\\n  - exp_id: c2_n500_deepseek\\n    role: primary\\n    result: significant\\n  - exp_id: c2_qw_n500\\n    role: primary\\n    result: significant\\n  depends_on:\\n  - D058\\n- id: D062\\n  date: 2026-05-14 19:37 UTC\\n  summary: Cron 监控改为 shell PID + sentinel 双机制，解决 profiling 实验 condition 切换时 PID 变化导致的反复误报\\n  rationale: c2_qw_n500 已第 3-4 次 cron 误报，每次触发 diagnose worker 浪费资源。根因：cron 监控 python\\n    PID 但 condition 切换时 PID 变化，且 slow path 只识别 tmux 不识别 screen。修复：(1) 改用 shell 脚本\\n    PID（全程不变）注册 cron (2) run script 末尾写 sentinel 供 fast path 检测 (3) PID 写入文件供排查。后续\\n    profiling 实验模板应默认包含 PID 文件 + sentinel 写入。\\n  related_experiments:\\n  - exp_id: c2_qw_n500\\n    role: trigger\\n    result: cron misfire fixed\\n  depends_on:\\n  - D061\\n\", \"total_chars\": 46741, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 49_

<details><summary>Logged reasoning block</summary>

```text
Now I have a comprehensive understanding of the decisions. Let me compile the checklist. Let me also check what figures are referenced.

Key decisions relevant to the update:
- D054: II use median + median bootstrap CI, no mean
- D059: d_z only for within-importance; for imp-vs-rand comparisons, only report Wilcoxon p + median_diff, no d_z
- D015: Use "emergent phase-strategy interaction" framing
- D056: C5b demoted to §8 future work
- D060: C8 LLaMA use "suggests"/"provides partial support"


- I need to verify the random II constraint and check where C5b actually sits in the current draft. Looking at the conclusion, it's appropriately scoped as a one-liner about phase-aware sparsity allocation, while the discussion section contains more detailed treatment of phase-aware compression budgets. D056 appears to be handling this correctly.

Now I'm checking whether the language around C5b actually claims implementation or just frames it as future work. The discussion treats it as an implication, and the conclusion motivates it as future direction, so it seems properly positioned. I should verify there's no overstatement about what was actually built.

For D060, I'm scanning the LLaMA results across the abstract, results section, discussion, and conclusion — the language consistently uses hedging like "suggests," "provides partial support," and "partially extends," which all seem appropriately cautious. The one phrase "The qualitative pattern replicates" in §5.5 is borderline since it's describing observations rather than making a strong claim, but it's probably acceptable.

Now I'm looking at the LLaMA cross-architecture table and noticing it reports d_z values for imp-vs-rand comparisons, which appears to violate D059's constraint that d_z shouldn't be reported for that comparison. The table structure needs adjustment. I'm checking for other instances that need updating—specifically looking for mentions of n=50 in the methodology section that should be n=500, and scanning the appendix for sample size references like n=49 or n=46 that also need correction. Now I'll compile everything into a comprehensive checklist organized by section, documenting each location that requires changes along with what needs to be modified.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "be042541-4b88-4f2a-95fc-bdc257801fa0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BHhZCCBLP5RZYto7Qi3fbA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 24029,
      "cache_read_input_tokens": 51265,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 24029
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

_source line 50_

决策文件已读取。现在综合所有信息产出更新清单。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "15b11fef-5303-4111-b66f-d3f15ec75c39",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BHhZCCBLP5RZYto7Qi3fbA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 24029,
      "cache_read_input_tokens": 51265,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 24029
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

_source line 51_

<details open><summary>🔧 Tool call — Write · `toolu_0197LRpCmTHtTSzG74E8z2BX`</summary>

````json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/n500_update_checklist.md",
  "content": "# n=500 更新清单\n\n> 论文：Phase-Modulated Compound Sparsity (EMNLP 2026 ARR)\n> 当前数据：n=50 MATH-500（DeepSeek n=49, Qwen n=46, LLaMA n=49）\n> 目标数据：n=500 MATH-500\n> 生成日期：2026-05-14\n> 硬约束：D054 (median only), D059 (within-imp d_z only), D015 (emergent interaction framing), D056 (C5b→future work), D060 (LLaMA→suggests)\n\n---\n\n## 统计汇总\n\n| 分类 | 数量 |\n|------|------|\n| data_update（数字替换） | 48 |\n| figure_update（重新生成） | 5 |\n| claim_update（措辞调整） | 8 |\n| structural（结构变动） | 3 |\n| constraint_check（硬约束合规） | 6 |\n| **总计** | **70** |\n\n---\n\n## §0 Abstract (abstract.tex)\n\n### A01 [data_update] Line 6 — 样本量\n- **当前**: `50 MATH-500 problems`\n- **替换**: `500 MATH-500 problems`\n- **依赖**: n=500 DeepSeek/Qwen 有效样本量（扣除 degenerate phase 后实际 n）\n\n### A02 [data_update] Line 7 — DeepSeek 主结果\n- **当前**: `median Interaction Index difference between low-sparsity and high-sparsity reasoning phases increases monotonically from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$`\n- **替换**: n=500 DeepSeek importance Δ 值（4 个 sparsity level）\n- **来源**: experiment_summary_table.json → median_diff\n\n### A03 [data_update] Line 7 — DeepSeek d_z 和 p\n- **当前**: `paired Cohen's $d_z$ growing from $0.44$ (small) to $0.80$ (large); Bonferroni-corrected permutation tests yield $p < 0.005$`\n- **替换**: n=500 DeepSeek within-importance paired d_z（4 值）+ 新 p-values\n- **注意**: D059 — 此处 d_z 是 within-importance (low−high)，合规 ✓\n\n### A04 [data_update] Line 8 — Random baseline 统计\n- **当前**: `Random eviction produces no significant phase modulation in 7/8 conditions; the single exception (Qwen $s{=}0.30$, $p{=}0.012$) shows negligible effect size ($d_z{=}{-}0.04$)`\n- **替换**: n=500 random 条件的 PASS/FAIL 计数 + 例外条件的 p 和效应量\n- **注意**: D059 — random 条件不报 d_z，改为 Wilcoxon p + median_diff\n\n### A05 [data_update] Line 9 — Crossover 数值\n- **当前**: `$\\widetilde{\\mathrm{II}} = 0.032$ vs.\\ $0.818$` 和 `$7.196$ vs.\\ $1.363$`\n- **替换**: n=500 s=0.25 crossover 的 4 个 II 中位数\n\n### A06 [data_update] Line 10 — Qwen 复现\n- **当前**: `$d_z \\geq 0.55$; Spearman $\\rho = 1.0$; gradient permutation $p = 0.043$`\n- **替换**: n=500 Qwen within-importance d_z + Spearman ρ + permutation p\n\n### A07 [data_update] Line 10 — LLaMA 数值\n- **当前**: `$d_z$ ($0.19 \\to 0.34$; $s{=}0.30$ Wilcoxon $p_{\\text{Bonf}} = 0.029$)`\n- **替换**: LLaMA 数据未变（n=49），但需确认是否也跑 n=500\n- **注意**: D059 违规 ⚠️ — 此 d_z 是 imp-vs-rand，应改为 Wilcoxon p + median_diff\n- **注意**: D060 — 当前用 \"suggests\"，合规 ✓\n\n### A08 [data_update] Line 10 — LLaMA 倍数比\n- **当前**: `${\\sim}$1/40 the absolute magnitude`\n- **替换**: 用 n=500 DeepSeek 数据重算 LLaMA/DeepSeek 比值\n\n---\n\n## §1 Introduction (introduction.tex)\n\n### I01 [data_update] Line 14 — DeepSeek 主结果\n- **当前**: `$0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$ ($d_z$: $0.44 \\to 0.80$; Bonferroni-corrected $p < 0.005$)`\n- **替换**: 与 A02/A03 同步\n\n### I02 [data_update] Line 15 — Qwen d_z\n- **当前**: `$d_z \\geq 0.55$`\n- **替换**: n=500 Qwen within-importance d_z 下界\n\n### I03 [data_update] Line 15 — LLaMA 倍数\n- **当前**: `$\\sim$1/40 the magnitude`\n- **替换**: 与 A08 同步\n\n### I04 [data_update] Line 16 — Random PASS/FAIL 统计\n- **当前**: `7/8 conditions non-significant`\n- **替换**: n=500 random PASS/FAIL 计数\n\n---\n\n## §4 Experimental Setup (methodology.tex)\n\n### M01 [data_update] Line 10 — 样本量\n- **当前**: `50 problems stratified from MATH-500`\n- **替换**: `500 problems from MATH-500`（去掉 \"stratified\"，500 ≈ 全集）\n\n### M02 [data_update] Line 18 — 偏度统计\n- **当前**: `mean/median ratios up to 43:1`\n- **替换**: n=500 的 mean/median ratio\n- **注意**: D054 — 此处引用 mean/median 比作为选择 median 的理由，合规 ✓\n\n### M03 [data_update] Line 22 — p-value 总结\n- **当前**: `All tests yield $p_{\\text{Bonf}} < 0.005$ at every sparsity level.`\n- **替换**: n=500 permutation test 结果\n\n---\n\n## §5 Results (results.tex)\n\n### R01 [data_update] Lines 8 — §5.1 aggregate Δ\n- **当前**: `$\\Delta$ increases from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$---a $37{\\times}$ amplification`\n- **替换**: n=500 Δ 值 + 新倍数\n\n### R02 [data_update] Line 8 — Random Δ 范围\n- **当前**: `$-0.02$ to $1.54$`\n- **替换**: n=500 random Δ 范围\n\n### R03 [data_update] Line 13 — Table 1 标题样本量\n- **当前**: `$n{=}50$ MATH-500 problems`\n- **替换**: `$n{=}500$`（或实际有效 n）\n\n### R04 [data_update] Lines 19-20 — Table 1 (aggregate-ii) 全部数据\n- **当前**:\n  ```\n  Importance & 0.39 & 1.48 & 7.16 & 14.59\n  Random     & 0.01 & −0.02 & 0.54 & 1.54\n  ```\n- **替换**: n=500 median Δ 值（8 个数字）\n\n### R05 [data_update] Line 29 — §5.2 severity gradient G\n- **当前**: `$69{\\times}$ at $s{=}0.15$ to $274{\\times}$ at $s{=}0.30$`\n- **替换**: n=500 G 值\n- **注意**: D031/D033 决定 gradient ratio 仅作辅助描述；确认 n=500 是否仍报 G\n\n### R06 [data_update] Line 29 — high-phase II 范围\n- **当前**: `$\\widetilde{\\mathrm{II}}_{\\textit{high}}$ ranges from $0.006$ to $0.053$`\n- **替换**: n=500 high-phase median II 范围\n\n### R07 [data_update] Line 29 — Random G 范围\n- **当前**: `$G \\approx 0.9$--$1.7{\\times}$`\n- **替换**: n=500 random G 范围\n\n### R08 [data_update] Lines 34, 40-50 — Table 2 (main-results) 全部数据\n- **当前**: \"50 problems\" + 24 个数据单元格（6列×4组）\n- **替换**: n=500 全部 per-phase median II + Δ + G（24 个数字 + caption 中 n）\n\n### R09 [figure_update] Lines 55-60 — Figure 1 (fig1_dose_response.pdf)\n- **当前**: 基于 n=50 bf16 数据\n- **操作**: 用 n=500 数据重新生成 fig1_dose_response.pdf\n- **注意**: caption 中 \"$69{\\times}$ to $274{\\times}$\" 需同步更新\n\n### R10 [data_update] Line 66 — §5.3 Crossover 数值\n- **当前**: `$0.032$ vs.\\ $0.818$`, `$7.196$ vs.\\ $1.363$---a $5.3{\\times}$ reversal`\n- **替换**: n=500 s=0.25 crossover 值 + 倍数\n\n### R11 [data_update] Line 71 — §5.4 Qwen Δ 范围\n- **当前**: `$\\Delta$ increases from $0.04$ at $s{=}0.15$ to $2.94$ at $s{=}0.30$`\n- **替换**: n=500 Qwen Δ 值\n\n### R12 [data_update] Line 71 — DeepSeek/Qwen 倍数比\n- **当前**: `${\\sim}1/5$ the magnitude`\n- **替换**: n=500 Qwen/DeepSeek 比值\n\n### R13 [data_update] Line 71 — Qwen 统计\n- **当前**: `Spearman $\\rho = 1.0$; gradient permutation $p = 0.043$`\n- **替换**: n=500 Qwen 对应统计量\n\n### R14 [data_update] Line 71 — Qwen s015 d_z\n- **当前**: `$d_z{=}0.28$, CI includes zero`\n- **替换**: n=500 Qwen s015 d_z + CI\n- **注意**: D052 预注册——若 s015 仍 ns，叙事改为 \"emerges above threshold\"\n\n### R15 [data_update] Line 71 — Qwen d_z 下界\n- **当前**: `$d_z \\geq 0.55$`\n- **替换**: n=500 Qwen s≥0.20 d_z 值\n\n### R16 [data_update] Line 77 — §5.5 LLaMA 样本量\n- **当前**: `$n{=}49$ paired problems`\n- **替换**: 确认 LLaMA 是否也跑 n=500；若仍 n=49 则保留\n\n### R17 [constraint_check] Lines 79 — §5.5 LLaMA d_z（D059 违规 ⚠️）\n- **当前**: `monotonically increasing paired $d_z$ ($0.19 \\to 0.26 \\to 0.29 \\to 0.34$)`\n- **问题**: 此 d_z 是 imp-vs-rand paired Cohen's d，D059 禁止报告\n- **修改**: 删除 imp-vs-rand d_z，改为 Wilcoxon p + median_diff\n\n### R18 [constraint_check] Lines 79 — LLaMA within-importance d_z\n- **当前**: `within-strategy phase gradient $d_z$ (low $-$ high) is consistently large at all sparsity levels ($d_z \\in [1.00, 1.12]$)`\n- **状态**: 合规 ✓（within-importance），数值可能需更新（若 LLaMA 重跑）\n\n### R19 [constraint_check] Lines 79 — LLaMA random d_z\n- **当前**: `$d_z \\in [0.35, 0.45]$`\n- **问题**: D059 — random 不报 d_z\n- **修改**: 改为 \"random eviction also shows non-trivial phase gradient\" + Wilcoxon p\n\n### R20 [data_update] Lines 81 — LLaMA 倍数比\n- **当前**: `${\\sim}40{\\times}$ smaller than DeepSeek and ${\\sim}7{\\times}$ smaller than Qwen`\n- **替换**: 用 n=500 DeepSeek/Qwen 数据重算比值\n\n### R21 [structural] Lines 83-98 — Table 3 (llama-cross-arch) 重构\n- **当前**: d_z 列报告 imp-vs-rand Cohen's d\n- **问题**: D059 违规 — 整列需要替换\n- **修改**: d_z 列改为 within-importance d_z（或删除 d_z 列，改为 Wilcoxon p + median_diff）\n- **数据**: 若 LLaMA 不重跑，数值不变但列定义需改\n\n### R22 [data_update] Lines 92-95 — Table 3 数据行\n- **当前**: 4 行 (d_z, Δ̃ [CI], p_Bonf)\n- **替换**: 若 LLaMA 重跑则全部更新；若不重跑，仅结构变动\n\n### R23 [data_update] Line 104 — §5.6 permutation test 结果\n- **当前**: `$p_{\\text{Bonf}} < 0.005$`, `$0.37$ at $s{=}0.15$ to $9.85$ at $s{=}0.30$`\n- **替换**: n=500 permutation test 统计\n\n### R24 [data_update] Lines 106 — DeepSeek d_z 范围\n- **当前**: `$d_z{=}0.44$ (small) to $d_z{=}0.80$ (large)`\n- **替换**: n=500 DeepSeek within-importance d_z\n\n### R25 [data_update] Lines 106 — Qwen d_z\n- **当前**: `$d_z{=}0.28$, CI includes zero`, `$d_z \\geq 0.55$`, `$d_z{=}0.89$/$1.02$ vs.\\ $0.68$/$0.80$`\n- **替换**: n=500 Qwen d_z 值\n\n### R26 [data_update] Lines 113-123 — Table 4 (cohens-d) 全部数据\n- **当前**: 4 行 × (DS d_z, Δ̃ [CI], QW d_z, Δ̃ [CI])\n- **替换**: n=500 paired d_z + bootstrap Δ̃ + CI（16 个数字）\n\n---\n\n## §6 Analysis (analysis.tex)\n\n### AN01 [data_update] Line 4 — Gini 系数范围\n- **当前**: `$0.030$--$0.081$ (DeepSeek) and $0.010$--$0.020$ (Qwen)`\n- **替换**: n=500 Gini Δ 范围（若 C4 entropy 分析基于 n=500 重跑）\n- **注意**: C4 已降为 supporting analysis (D045/D046)，数值可能不变\n\n### AN02 [data_update] Line 6 — DeepSeek entropy Δ 范围\n- **当前**: `$\\Delta\\mathcal{H} \\in [-0.047, -0.040]$`\n- **替换**: 若 C4 基于 n=500 重跑则更新\n\n### AN03 [data_update] Line 6 — Qwen entropy 反转\n- **当前**: `$s{=}0.25$ ($\\Delta\\mathcal{H} = +0.045$)`\n- **替换**: 若 C4 基于 n=500 重跑则更新\n\n---\n\n## §7 Discussion (discussion.tex)\n\n### D01 [data_update] Line 5 — Gradient 范围\n- **当前**: `$69$--$274{\\times}$`\n- **替换**: 与 R05 同步\n\n### D02 [data_update] Line 5 — Crossover 数值\n- **当前**: `$\\widetilde{\\mathrm{II}} = 0.032$ vs.\\ $0.818$` 和 `$7.196$ vs.\\ $1.363$`\n- **替换**: 与 R10 同步\n\n### D03 [data_update] Line 11 — LLaMA 倍数\n- **当前**: `${\\sim}40{\\times}$ smaller than DeepSeek, ${\\sim}7{\\times}$ smaller than Qwen`\n- **替换**: 与 R20 同步\n\n### D04 [constraint_check] Line 11 — LLaMA d_z（D059 违规 ⚠️）\n- **当前**: `within-strategy phase gradient $d_z \\geq 1.0$`\n- **状态**: 这是 within-importance d_z，合规 ✓\n\n### D05 [constraint_check] Line 11 — LLaMA random d_z（D059 违规 ⚠️）\n- **当前**: `$d_z \\in [0.35, 0.45]$`\n- **修改**: 与 R19 同步——删除 d_z，改为定性描述 + Wilcoxon p\n\n### D06 [claim_update] Line 11 — LLaMA 语言（D060）\n- **当前**: `provides partial support for the qualitative pattern`\n- **状态**: 合规 ✓（\"partial support\"）\n\n---\n\n## §8 Conclusion (conclusion.tex)\n\n### C01 [data_update] Line 4 — Gradient 范围\n- **当前**: `$69{\\times}$ to $274{\\times}$`\n- **替换**: 与 R05 同步\n\n### C02 [data_update] Line 4 — d_z 范围\n- **当前**: `$d_z$: $0.44 \\to 0.80$`\n- **替换**: 与 R24 同步\n\n### C03 [data_update] Line 4 — Random PASS/FAIL\n- **当前**: `7/8 conditions non-significant`\n- **替换**: 与 I04 同步\n\n### C04 [data_update] Line 4 — Qwen d_z\n- **当前**: `$d_z \\geq 0.55$`\n- **替换**: 与 R15 同步\n\n### C05 [data_update] Line 4 — LLaMA 倍数\n- **当前**: `$\\sim$1/40 the magnitude`\n- **替换**: 与 A08 同步\n\n### C06 [constraint_check] — C5b future work（D056）\n- **当前**: `These findings motivate phase-aware sparsity allocation for reasoning model deployment.`\n- **状态**: 合规 ✓ — 作为 motivation 而非 contribution claim\n\n---\n\n## Limitations (limitations.tex)\n\n### L01 [data_update] Line 1 — 架构描述\n- **状态**: 无直接 n=50 数据，无需数字更新\n\n### L02 [claim_update] Line 4 — 样本量描述\n- **当前**: 未直接提及 n=50，但 \"exclusively on MATH-500\" 成立\n- **替换**: n=500 后可加 \"using 500 problems from MATH-500\"\n\n---\n\n## Appendix A (appendix.tex) — Formulation + Multiplicative Null\n\n### AP01 [data_update] Line 38 — Multiplicative null G 范围\n- **当前**: `$G_{\\times} = 58$--$241{\\times}$`\n- **替换**: n=500 multiplicative null G 值（需重算）\n\n---\n\n## Appendix B (appendix_results.tex) — Cross-Model Summary\n\n### AR01 [data_update] Line 7 — Per-problem concordance\n- **当前**: `mean $\\rho = -0.11$, $p = 0.926$`\n- **替换**: n=500 cross-model concordance（Spearman ρ + p）\n\n### AR02 [data_update] Line 10 — Random PASS/FAIL 模式\n- **当前**: `3/4 FAIL`, `4/4 FAIL`\n- **替换**: n=500 random PASS/FAIL 计数\n\n### AR03 [data_update] Line 10 — Qwen random s030 例外\n- **当前**: `$p = 0.012$`, `$d_z = -0.04$`\n- **替换**: n=500 结果\n- **注意**: D059 — 不报 d_z，改为 Wilcoxon p + median_diff\n\n---\n\n## Appendix C (appendix_moved.tex) — Crossover + Cross-Model + Permutation + Analysis\n\n### AM01 [data_update] Line 11 — Crossover 全部数值\n- **当前**: `$0.032$ vs.\\ $0.818$`, `$7.196$ vs.\\ $1.363$`, `$5.3{\\times}$`, `$3.9{\\times}$, $5.4{\\times}$, $5.3{\\times}$, $3.6{\\times}$`\n- **替换**: n=500 crossover 值（所有 4 个 sparsity level 的 reversal magnitude）\n\n### AM02 [figure_update] Lines 13-18 — Figure 3 (fig3_crossover.pdf)\n- **操作**: 用 n=500 数据重新生成\n- **caption**: `$5.3{\\times}$` 需同步更新\n\n### AM03 [data_update] Line 26 — Qwen 排除数\n- **当前**: `Four of the 50 problems are excluded`, `$n{=}46$`, `$n{=}49$`\n- **替换**: n=500 的 DeepSeek/Qwen 有效 n\n\n### AM04 [data_update] Lines 39-40 — Table (cross-model) 全部数据\n- **当前**: DeepSeek [0.39, 1.48, 7.16, 14.59], Qwen [0.04, 0.23, 1.27, 2.94]\n- **替换**: n=500 median Δ 值（8 个数字）\n\n### AM05 [figure_update] Lines 45-50 — Figure 5 (fig5_crossmodel.pdf)\n- **操作**: 用 n=500 数据重新生成\n- **caption**: \"one-fifth\" 比例需同步更新\n\n### AM06 [data_update] Lines 52-53 — Per-problem concordance（重复 AR01）\n- **替换**: 与 AR01 同步\n\n### AM07 [data_update] Lines 55-56 — Random PASS/FAIL（重复 AR02/AR03）\n- **替换**: 与 AR02/AR03 同步\n\n### AM08 [data_update] Lines 62, 73 — Permutation test 样本量\n- **当前**: `$n{=}49$`\n- **替换**: n=500 有效 n\n\n### AM09 [data_update] Lines 68 — CI lower bounds\n- **当前**: `$0.19 \\to 0.69 \\to 1.66 \\to 6.70$`\n- **替换**: n=500 CI lower bounds\n\n### AM10 [data_update] Lines 79-82 — Table (permutation) 全部数据\n- **当前**: 4 行 (observed Δ̃, 95% CI, p_Bonf)\n- **替换**: n=500 permutation test 结果（12 个数字）\n\n### AM11 [figure_update] Lines 87-92 — Figure 4 (fig4_bootstrap.pdf)\n- **操作**: 用 n=500 数据重新生成\n\n### AM12 [data_update] Lines 111-122 — Table (discrimination-metrics-full) 全部数据\n- **当前**: 8 行 (ΔGini, ΔCV)\n- **替换**: 若 C4 分析基于 n=500 重跑则更新（16 个数字）\n\n### AM13 [data_update] Lines 137-139 — Entropy delta 描述\n- **当前**: DeepSeek `$\\Delta\\mathcal{H} \\in [-0.047, -0.040]$`, Qwen s025 `$+0.045$`\n- **替换**: 若 C4 分析基于 n=500 重跑则更新\n\n### AM14 [data_update] Lines 149-162 — Table (entropy-deltas) 全部数据\n- **当前**: 8 行\n- **替换**: 若 C4 分析基于 n=500 重跑则更新\n\n---\n\n## Appendix D (appendix_disc_analysis.tex) — Extended Discussion + Limitations\n\n### AD01 [data_update] Line 4 — Random Gini 范围\n- **当前**: `$-0.031$ to $-0.073$; Qwen: $-0.019$ to $-0.045$`\n- **替换**: 若 C4 基于 n=500 重跑则更新\n\n### AD02 [data_update] Line 11 — High-phase II 上限\n- **当前**: `$\\widetilde{\\mathrm{II}}_{\\text{high}} < 0.06$ at $s \\leq 0.30$`; `$s = 0.35$, high-phase II rises to $0.105$`\n- **替换**: n=500 high-phase median II 值\n\n### AD03 [data_update] Line 14 — Random 7/8 统计\n- **当前**: `7/8`, `$p{=}0.012$`, `$d_z{=}{-}0.04$`\n- **替换**: 与 A04 同步\n- **注意**: D059 — 不报 d_z\n\n### AD04 [data_update] Lines 44-47 — 统计范围详情\n- **当前**: `$n{=}49$ ... $n{=}46$`, mean/median ratio `${\\sim}1.6{:}1$`, permutation CI 值\n- **替换**: n=500 统计\n\n### AD05 [data_update] Line 49 — Qwen random s030 例外\n- **当前**: `$p{=}0.012$`, `$d_z{=}{-}0.04$`\n- **替换**: 与 AR03 同步\n- **注意**: D059 — 不报 d_z\n\n### AD06 [data_update] Lines 53-57 — Growth rate 描述\n- **当前**: `$3.8{\\times} \\to 4.8{\\times} \\to 2.0{\\times}$`\n- **替换**: n=500 Δ growth rate\n\n---\n\n## 图表重新生成清单\n\n| # | 文件名 | 数据来源 | 引用位置 |\n|---|--------|----------|----------|\n| F1 | fig1_dose_response.pdf | n=500 DeepSeek imp+rand G vs s | results.tex:57, caption:58 |\n| F2 | fig3_crossover.pdf | n=500 DeepSeek s=0.25 crossover | appendix_moved.tex:15 |\n| F3 | fig4_bootstrap.pdf | n=500 permutation test forest plot | appendix_moved.tex:89 |\n| F4 | fig5_crossmodel.pdf | n=500 DeepSeek+Qwen Δ comparison | appendix_moved.tex:47 |\n| F5 | (unnamed hero figure if separate) | 确认是否与 fig1 相同 | results.tex:57 |\n\n---\n\n## 硬约束合规审查\n\n### HC01 [D054] II 只报 median + median bootstrap CI ✅\n- abstract/results/discussion 全文使用 median ($\\widetilde{\\mathrm{II}}$)\n- methodology.tex:18 提及 mean/median ratio 作为选择 median 的理由 ✓\n- **注意**: n=500 更新时确认所有新数字均为 median\n\n### HC02 [D059] d_z 只报 within-importance ⚠️ 6 处违规\n| 位置 | 当前内容 | 问题 |\n|------|---------|------|\n| abstract.tex:8 | random `$d_z{=}{-}0.04$` | imp-vs-rand d_z |\n| results.tex:79 | LLaMA `$d_z$ ($0.19 \\to 0.34$)` | imp-vs-rand d_z |\n| results.tex:79 | random `$d_z \\in [0.35, 0.45]$` | random d_z |\n| results.tex:88-97 | Table 3 d_z 列 | imp-vs-rand d_z |\n| discussion.tex:11 | `$d_z \\in [0.35, 0.45]$` | random d_z |\n| appendix_disc_analysis.tex:14,49 | `$d_z{=}{-}0.04$` | random d_z |\n\n**修改方案**: 所有 imp-vs-rand 和 random d_z 替换为 Wilcoxon p + median_diff；Table 3 d_z 列替换为 within-importance d_z 或移除\n\n### HC03 [D015] Framing: emergent phase-strategy interaction ✅\n- abstract.tex:4 使用 \"emergent phase-strategy interaction\" ✓\n- 全文无 \"importance is broken\" 叙事 ✓\n\n### HC04 [D056] C5b 已降为 §8 future work ✅\n- discussion.tex:8 讨论 phase-aware budget 作为 implication（未 claim 实现）✓\n- conclusion.tex:5 \"motivate phase-aware sparsity allocation\" ✓\n- **注意**: D056 确认 c5b_pilot gate_failed (oracle 18% < 30%)，论文不应 claim C5b 成功\n\n### HC05 [D060] C8 LLaMA 用 suggests/partial support ✅\n- abstract.tex:10 \"suggests cross-architecture generalization\" ✓\n- discussion.tex:11 \"provides partial support\" ✓\n- conclusion.tex:4 \"partially extends\" ✓\n- results.tex:77-81 \"The qualitative pattern replicates\" — **borderline**，建议改为 \"The qualitative pattern is directionally consistent\"\n\n### HC06 [硬约束 #6] Random 也有正 II，区分信号是 gradient ✅\n- results.tex Table 2 显示 random 有正 II ✓\n- 叙事正确区分：\"compound severity depends qualitatively on eviction strategy\" ✓\n- **注意**: n=500 random 数据可能有不同 pattern，需重新验证此叙事\n\n---\n\n## 按 Section 分布\n\n| Section | 更新点数 |\n|---------|---------|\n| Abstract | 8 |\n| Introduction | 4 |\n| Methodology | 3 |\n| Results | 26 |\n| Analysis | 3 |\n| Discussion | 6 |\n| Conclusion | 6 |\n| Limitations | 2 |\n| Appendix (formulation) | 1 |\n| Appendix (results summary) | 3 |\n| Appendix (moved content) | 14 |\n| Appendix (disc+limitations) | 6 |\n| **Total** | **82** (含重复引用) |\n| **Unique** | **~70** |\n\n---\n\n## 高风险点（可能需要改叙事）\n\n### RISK-1: Qwen s015 是否仍然 non-significant\n- D052 预注册：若 n=500 Qwen s015 仍 ns，叙事改为 \"compound effect emerges above a model-dependent threshold\"\n- D061 已确认 n=500 下 Qwen s015 显著 (p<0.0001)——**如果最终数据确认，此风险解除**\n- 影响范围：abstract, introduction, results §5.4, §5.6, conclusion\n\n### RISK-2: Random PASS/FAIL 模式可能变化\n- n=50 下 7/8 FAIL（Qwen s030 borderline PASS d≈0）\n- n=500 功效更高，可能检测到更多 borderline 显著\n- 影响范围：需重新评估 \"no significant phase modulation\" 叙事\n- D059 保护：不报 random d_z，用 Wilcoxon p + median_diff 更 robust\n\n### RISK-3: LLaMA 数据是否跑 n=500\n- 当前 LLaMA 仅 n=49\n- 若不重跑：DeepSeek/Qwen 倍数比需重算（分母变了）\n- 若重跑：全部 LLaMA 数据需更新\n\n### RISK-4: D059 Table 3 重构\n- Table 3 (llama-cross-arch) 的核心组织方式围绕 imp-vs-rand d_z\n- 删除 d_z 列后需要替代结构，可能影响 §5.5 整段叙事\n\n### RISK-5: Crossover pattern 在 n=500 是否稳定\n- crossover 是论文的一个 key finding\n- n=500 的 crossover 倍数和位置可能变化\n- 影响范围：abstract, results §5.3, discussion, appendix\n\n### RISK-6: C4 entropy 分析是否需要基于 n=500 重跑\n- 当前 C4 降级为 supporting analysis (D045/D046)\n- 若不重跑：analysis.tex 和 appendix 表格保留 n=50 数据，需标注\n- 若重跑：AN01-AN03, AM12-AM14, AD01 全部更新\n"
}
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "c85a3d70-eac7-47ca-98d5-ee342c2b0f82",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BHhZCCBLP5RZYto7Qi3fbA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 24029,
      "cache_read_input_tokens": 51265,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 24029
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

_source line 52 · 2026-05-14T20:48:55.974Z_

<details><summary>↩ Tool result · `toolu_0197LRpCmTHtTSzG74E8z2BX`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/n500_update_checklist.md
```

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "d87f0c2d-5b4b-46f4-a7d7-96d6d0211e37",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/n500_update_checklist.md",
    "content": "# n=500 更新清单\n\n> 论文：Phase-Modulated Compound Sparsity (EMNLP 2026 ARR)\n> 当前数据：n=50 MATH-500（DeepSeek n=49, Qwen n=46, LLaMA n=49）\n> 目标数据：n=500 MATH-500\n> 生成日期：2026-05-14\n> 硬约束：D054 (median only), D059 (within-imp d_z only), D015 (emergent interaction framing), D056 (C5b→future work), D060 (LLaMA→suggests)\n\n---\n\n## 统计汇总\n\n| 分类 | 数量 |\n|------|------|\n| data_update（数字替换） | 48 |\n| figure_update（重新生成） | 5 |\n| claim_update（措辞调整） | 8 |\n| structural（结构变动） | 3 |\n| constraint_check（硬约束合规） | 6 |\n| **总计** | **70** |\n\n---\n\n## §0 Abstract (abstract.tex)\n\n### A01 [data_update] Line 6 — 样本量\n- **当前**: `50 MATH-500 problems`\n- **替换**: `500 MATH-500 problems`\n- **依赖**: n=500 DeepSeek/Qwen 有效样本量（扣除 degenerate phase 后实际 n）\n\n### A02 [data_update] Line 7 — DeepSeek 主结果\n- **当前**: `median Interaction Index difference between low-sparsity and high-sparsity reasoning phases increases monotonically from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$`\n- **替换**: n=500 DeepSeek importance Δ 值（4 个 sparsity level）\n- **来源**: experiment_summary_table.json → median_diff\n\n### A03 [data_update] Line 7 — DeepSeek d_z 和 p\n- **当前**: `paired Cohen's $d_z$ growing from $0.44$ (small) to $0.80$ (large); Bonferroni-corrected permutation tests yield $p < 0.005$`\n- **替换**: n=500 DeepSeek within-importance paired d_z（4 值）+ 新 p-values\n- **注意**: D059 — 此处 d_z 是 within-importance (low−high)，合规 ✓\n\n### A04 [data_update] Line 8 — Random baseline 统计\n- **当前**: `Random eviction produces no significant phase modulation in 7/8 conditions; the single exception (Qwen $s{=}0.30$, $p{=}0.012$) shows negligible effect size ($d_z{=}{-}0.04$)`\n- **替换**: n=500 random 条件的 PASS/FAIL 计数 + 例外条件的 p 和效应量\n- **注意**: D059 — random 条件不报 d_z，改为 Wilcoxon p + median_diff\n\n### A05 [data_update] Line 9 — Crossover 数值\n- **当前**: `$\\widetilde{\\mathrm{II}} = 0.032$ vs.\\ $0.818$` 和 `$7.196$ vs.\\ $1.363$`\n- **替换**: n=500 s=0.25 crossover 的 4 个 II 中位数\n\n### A06 [data_update] Line 10 — Qwen 复现\n- **当前**: `$d_z \\geq 0.55$; Spearman $\\rho = 1.0$; gradient permutation $p = 0.043$`\n- **替换**: n=500 Qwen within-importance d_z + Spearman ρ + permutation p\n\n### A07 [data_update] Line 10 — LLaMA 数值\n- **当前**: `$d_z$ ($0.19 \\to 0.34$; $s{=}0.30$ Wilcoxon $p_{\\text{Bonf}} = 0.029$)`\n- **替换**: LLaMA 数据未变（n=49），但需确认是否也跑 n=500\n- **注意**: D059 违规 ⚠️ — 此 d_z 是 imp-vs-rand，应改为 Wilcoxon p + median_diff\n- **注意**: D060 — 当前用 \"suggests\"，合规 ✓\n\n### A08 [data_update] Line 10 — LLaMA 倍数比\n- **当前**: `${\\sim}$1/40 the absolute magnitude`\n- **替换**: 用 n=500 DeepSeek 数据重算 LLaMA/DeepSeek 比值\n\n---\n\n## §1 Introduction (introduction.tex)\n\n### I01 [data_update] Line 14 — DeepSeek 主结果\n- **当前**: `$0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$ ($d_z$: $0.44 \\to 0.80$; Bonferroni-corrected $p < 0.005$)`\n- **替换**: 与 A02/A03 同步\n\n### I02 [data_update] Line 15 — Qwen d_z\n- **当前**: `$d_z \\geq 0.55$`\n- **替换**: n=500 Qwen within-importance d_z 下界\n\n### I03 [data_update] Line 15 — LLaMA 倍数\n- **当前**: `$\\sim$1/40 the magnitude`\n- **替换**: 与 A08 同步\n\n### I04 [data_update] Line 16 — Random PASS/FAIL 统计\n- **当前**: `7/8 conditions non-significant`\n- **替换**: n=500 random PASS/FAIL 计数\n\n---\n\n## §4 Experimental Setup (methodology.tex)\n\n### M01 [data_update] Line 10 — 样本量\n- **当前**: `50 problems stratified from MATH-500`\n- **替换**: `500 problems from MATH-500`（去掉 \"stratified\"，500 ≈ 全集）\n\n### M02 [data_update] Line 18 — 偏度统计\n- **当前**: `mean/median ratios up to 43:1`\n- **替换**: n=500 的 mean/median ratio\n- **注意**: D054 — 此处引用 mean/median 比作为选择 median 的理由，合规 ✓\n\n### M03 [data_update] Line 22 — p-value 总结\n- **当前**: `All tests yield $p_{\\text{Bonf}} < 0.005$ at every sparsity level.`\n- **替换**: n=500 permutation test 结果\n\n---\n\n## §5 Results (results.tex)\n\n### R01 [data_update] Lines 8 — §5.1 aggregate Δ\n- **当前**: `$\\Delta$ increases from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$---a $37{\\times}$ amplification`\n- **替换**: n=500 Δ 值 + 新倍数\n\n### R02 [data_update] Line 8 — Random Δ 范围\n- **当前**: `$-0.02$ to $1.54$`\n- **替换**: n=500 random Δ 范围\n\n### R03 [data_update] Line 13 — Table 1 标题样本量\n- **当前**: `$n{=}50$ MATH-500 problems`\n- **替换**: `$n{=}500$`（或实际有效 n）\n\n### R04 [data_update] Lines 19-20 — Table 1 (aggregate-ii) 全部数据\n- **当前**:\n  ```\n  Importance & 0.39 & 1.48 & 7.16 & 14.59\n  Random     & 0.01 & −0.02 & 0.54 & 1.54\n  ```\n- **替换**: n=500 median Δ 值（8 个数字）\n\n### R05 [data_update] Line 29 — §5.2 severity gradient G\n- **当前**: `$69{\\times}$ at $s{=}0.15$ to $274{\\times}$ at $s{=}0.30$`\n- **替换**: n=500 G 值\n- **注意**: D031/D033 决定 gradient ratio 仅作辅助描述；确认 n=500 是否仍报 G\n\n### R06 [data_update] Line 29 — high-phase II 范围\n- **当前**: `$\\widetilde{\\mathrm{II}}_{\\textit{high}}$ ranges from $0.006$ to $0.053$`\n- **替换**: n=500 high-phase median II 范围\n\n### R07 [data_update] Line 29 — Random G 范围\n- **当前**: `$G \\approx 0.9$--$1.7{\\times}$`\n- **替换**: n=500 random G 范围\n\n### R08 [data_update] Lines 34, 40-50 — Table 2 (main-results) 全部数据\n- **当前**: \"50 problems\" + 24 个数据单元格（6列×4组）\n- **替换**: n=500 全部 per-phase median II + Δ + G（24 个数字 + caption 中 n）\n\n### R09 [figure_update] Lines 55-60 — Figure 1 (fig1_dose_response.pdf)\n- **当前**: 基于 n=50 bf16 数据\n- **操作**: 用 n=500 数据重新生成 fig1_dose_response.pdf\n- **注意**: caption 中 \"$69{\\times}$ to $274{\\times}$\" 需同步更新\n\n### R10 [data_update] Line 66 — §5.3 Crossover 数值\n- **当前**: `$0.032$ vs.\\ $0.818$`, `$7.196$ vs.\\ $1.363$---a $5.3{\\times}$ reversal`\n- **替换**: n=500 s=0.25 crossover 值 + 倍数\n\n### R11 [data_update] Line 71 — §5.4 Qwen Δ 范围\n- **当前**: `$\\Delta$ increases from $0.04$ at $s{=}0.15$ to $2.94$ at $s{=}0.30$`\n- **替换**: n=500 Qwen Δ 值\n\n### R12 [data_update] Line 71 — DeepSeek/Qwen 倍数比\n- **当前**: `${\\sim}1/5$ the magnitude`\n- **替换**: n=500 Qwen/DeepSeek 比值\n\n### R13 [data_update] Line 71 — Qwen 统计\n- **当前**: `Spearman $\\rho = 1.0$; gradient permutation $p = 0.043$`\n- **替换**: n=500 Qwen 对应统计量\n\n### R14 [data_update] Line 71 — Qwen s015 d_z\n- **当前**: `$d_z{=}0.28$, CI includes zero`\n- **替换**: n=500 Qwen s015 d_z + CI\n- **注意**: D052 预注册——若 s015 仍 ns，叙事改为 \"emerges above threshold\"\n\n### R15 [data_update] Line 71 — Qwen d_z 下界\n- **当前**: `$d_z \\geq 0.55$`\n- **替换**: n=500 Qwen s≥0.20 d_z 值\n\n### R16 [data_update] Line 77 — §5.5 LLaMA 样本量\n- **当前**: `$n{=}49$ paired problems`\n- **替换**: 确认 LLaMA 是否也跑 n=500；若仍 n=49 则保留\n\n### R17 [constraint_check] Lines 79 — §5.5 LLaMA d_z（D059 违规 ⚠️）\n- **当前**: `monotonically increasing paired $d_z$ ($0.19 \\to 0.26 \\to 0.29 \\to 0.34$)`\n- **问题**: 此 d_z 是 imp-vs-rand paired Cohen's d，D059 禁止报告\n- **修改**: 删除 imp-vs-rand d_z，改为 Wilcoxon p + median_diff\n\n### R18 [constraint_check] Lines 79 — LLaMA within-importance d_z\n- **当前**: `within-strategy phase gradient $d_z$ (low $-$ high) is consistently large at all sparsity levels ($d_z \\in [1.00, 1.12]$)`\n- **状态**: 合规 ✓（within-importance），数值可能需更新（若 LLaMA 重跑）\n\n### R19 [constraint_check] Lines 79 — LLaMA random d_z\n- **当前**: `$d_z \\in [0.35, 0.45]$`\n- **问题**: D059 — random 不报 d_z\n- **修改**: 改为 \"random eviction also shows non-trivial phase gradient\" + Wilcoxon p\n\n### R20 [data_update] Lines 81 — LLaMA 倍数比\n- **当前**: `${\\sim}40{\\times}$ smaller than DeepSeek and ${\\sim}7{\\times}$ smaller than Qwen`\n- **替换**: 用 n=500 DeepSeek/Qwen 数据重算比值\n\n### R21 [structural] Lines 83-98 — Table 3 (llama-cross-arch) 重构\n- **当前**: d_z 列报告 imp-vs-rand Cohen's d\n- **问题**: D059 违规 — 整列需要替换\n- **修改**: d_z 列改为 within-importance d_z（或删除 d_z 列，改为 Wilcoxon p + median_diff）\n- **数据**: 若 LLaMA 不重跑，数值不变但列定义需改\n\n### R22 [data_update] Lines 92-95 — Table 3 数据行\n- **当前**: 4 行 (d_z, Δ̃ [CI], p_Bonf)\n- **替换**: 若 LLaMA 重跑则全部更新；若不重跑，仅结构变动\n\n### R23 [data_update] Line 104 — §5.6 permutation test 结果\n- **当前**: `$p_{\\text{Bonf}} < 0.005$`, `$0.37$ at $s{=}0.15$ to $9.85$ at $s{=}0.30$`\n- **替换**: n=500 permutation test 统计\n\n### R24 [data_update] Lines 106 — DeepSeek d_z 范围\n- **当前**: `$d_z{=}0.44$ (small) to $d_z{=}0.80$ (large)`\n- **替换**: n=500 DeepSeek within-importance d_z\n\n### R25 [data_update] Lines 106 — Qwen d_z\n- **当前**: `$d_z{=}0.28$, CI includes zero`, `$d_z \\geq 0.55$`, `$d_z{=}0.89$/$1.02$ vs.\\ $0.68$/$0.80$`\n- **替换**: n=500 Qwen d_z 值\n\n### R26 [data_update] Lines 113-123 — Table 4 (cohens-d) 全部数据\n- **当前**: 4 行 × (DS d_z, Δ̃ [CI], QW d_z, Δ̃ [CI])\n- **替换**: n=500 paired d_z + bootstrap Δ̃ + CI（16 个数字）\n\n---\n\n## §6 Analysis (analysis.tex)\n\n### AN01 [data_update] Line 4 — Gini 系数范围\n- **当前**: `$0.030$--$0.081$ (DeepSeek) and $0.010$--$0.020$ (Qwen)`\n- **替换**: n=500 Gini Δ 范围（若 C4 entropy 分析基于 n=500 重跑）\n- **注意**: C4 已降为 supporting analysis (D045/D046)，数值可能不变\n\n### AN02 [data_update] Line 6 — DeepSeek entropy Δ 范围\n- **当前**: `$\\Delta\\mathcal{H} \\in [-0.047, -0.040]$`\n- **替换**: 若 C4 基于 n=500 重跑则更新\n\n### AN03 [data_update] Line 6 — Qwen entropy 反转\n- **当前**: `$s{=}0.25$ ($\\Delta\\mathcal{H} = +0.045$)`\n- **替换**: 若 C4 基于 n=500 重跑则更新\n\n---\n\n## §7 Discussion (discussion.tex)\n\n### D01 [data_update] Line 5 — Gradient 范围\n- **当前**: `$69$--$274{\\times}$`\n- **替换**: 与 R05 同步\n\n### D02 [data_update] Line 5 — Crossover 数值\n- **当前**: `$\\widetilde{\\mathrm{II}} = 0.032$ vs.\\ $0.818$` 和 `$7.196$ vs.\\ $1.363$`\n- **替换**: 与 R10 同步\n\n### D03 [data_update] Line 11 — LLaMA 倍数\n- **当前**: `${\\sim}40{\\times}$ smaller than DeepSeek, ${\\sim}7{\\times}$ smaller than Qwen`\n- **替换**: 与 R20 同步\n\n### D04 [constraint_check] Line 11 — LLaMA d_z（D059 违规 ⚠️）\n- **当前**: `within-strategy phase gradient $d_z \\geq 1.0$`\n- **状态**: 这是 within-importance d_z，合规 ✓\n\n### D05 [constraint_check] Line 11 — LLaMA random d_z（D059 违规 ⚠️）\n- **当前**: `$d_z \\in [0.35, 0.45]$`\n- **修改**: 与 R19 同步——删除 d_z，改为定性描述 + Wilcoxon p\n\n### D06 [claim_update] Line 11 — LLaMA 语言（D060）\n- **当前**: `provides partial support for the qualitative pattern`\n- **状态**: 合规 ✓（\"partial support\"）\n\n---\n\n## §8 Conclusion (conclusion.tex)\n\n### C01 [data_update] Line 4 — Gradient 范围\n- **当前**: `$69{\\times}$ to $274{\\times}$`\n- **替换**: 与 R05 同步\n\n### C02 [data_update] Line 4 — d_z 范围\n- **当前**: `$d_z$: $0.44 \\to 0.80$`\n- **替换**: 与 R24 同步\n\n### C03 [data_update] Line 4 — Random PASS/FAIL\n- **当前**: `7/8 conditions non-significant`\n- **替换**: 与 I04 同步\n\n### C04 [data_update] Line 4 — Qwen d_z\n- **当前**: `$d_z \\geq 0.55$`\n- **替换**: 与 R15 同步\n\n### C05 [data_update] Line 4 — LLaMA 倍数\n- **当前**: `$\\sim$1/40 the magnitude`\n- **替换**: 与 A08 同步\n\n### C06 [constraint_check] — C5b future work（D056）\n- **当前**: `These findings motivate phase-aware sparsity allocation for reasoning model deployment.`\n- **状态**: 合规 ✓ — 作为 motivation 而非 contribution claim\n\n---\n\n## Limitations (limitations.tex)\n\n### L01 [data_update] Line 1 — 架构描述\n- **状态**: 无直接 n=50 数据，无需数字更新\n\n### L02 [claim_update] Line 4 — 样本量描述\n- **当前**: 未直接提及 n=50，但 \"exclusively on MATH-500\" 成立\n- **替换**: n=500 后可加 \"using 500 problems from MATH-500\"\n\n---\n\n## Appendix A (appendix.tex) — Formulation + Multiplicative Null\n\n### AP01 [data_update] Line 38 — Multiplicative null G 范围\n- **当前**: `$G_{\\times} = 58$--$241{\\times}$`\n- **替换**: n=500 multiplicative null G 值（需重算）\n\n---\n\n## Appendix B (appendix_results.tex) — Cross-Model Summary\n\n### AR01 [data_update] Line 7 — Per-problem concordance\n- **当前**: `mean $\\rho = -0.11$, $p = 0.926$`\n- **替换**: n=500 cross-model concordance（Spearman ρ + p）\n\n### AR02 [data_update] Line 10 — Random PASS/FAIL 模式\n- **当前**: `3/4 FAIL`, `4/4 FAIL`\n- **替换**: n=500 random PASS/FAIL 计数\n\n### AR03 [data_update] Line 10 — Qwen random s030 例外\n- **当前**: `$p = 0.012$`, `$d_z = -0.04$`\n- **替换**: n=500 结果\n- **注意**: D059 — 不报 d_z，改为 Wilcoxon p + median_diff\n\n---\n\n## Appendix C (appendix_moved.tex) — Crossover + Cross-Model + Permutation + Analysis\n\n### AM01 [data_update] Line 11 — Crossover 全部数值\n- **当前**: `$0.032$ vs.\\ $0.818$`, `$7.196$ vs.\\ $1.363$`, `$5.3{\\times}$`, `$3.9{\\times}$, $5.4{\\times}$, $5.3{\\times}$, $3.6{\\times}$`\n- **替换**: n=500 crossover 值（所有 4 个 sparsity level 的 reversal magnitude）\n\n### AM02 [figure_update] Lines 13-18 — Figure 3 (fig3_crossover.pdf)\n- **操作**: 用 n=500 数据重新生成\n- **caption**: `$5.3{\\times}$` 需同步更新\n\n### AM03 [data_update] Line 26 — Qwen 排除数\n- **当前**: `Four of the 50 problems are excluded`, `$n{=}46$`, `$n{=}49$`\n- **替换**: n=500 的 DeepSeek/Qwen 有效 n\n\n### AM04 [data_update] Lines 39-40 — Table (cross-model) 全部数据\n- **当前**: DeepSeek [0.39, 1.48, 7.16, 14.59], Qwen [0.04, 0.23, 1.27, 2.94]\n- **替换**: n=500 median Δ 值（8 个数字）\n\n### AM05 [figure_update] Lines 45-50 — Figure 5 (fig5_crossmodel.pdf)\n- **操作**: 用 n=500 数据重新生成\n- **caption**: \"one-fifth\" 比例需同步更新\n\n### AM06 [data_update] Lines 52-53 — Per-problem concordance（重复 AR01）\n- **替换**: 与 AR01 同步\n\n### AM07 [data_update] Lines 55-56 — Random PASS/FAIL（重复 AR02/AR03）\n- **替换**: 与 AR02/AR03 同步\n\n### AM08 [data_update] Lines 62, 73 — Permutation test 样本量\n- **当前**: `$n{=}49$`\n- **替换**: n=500 有效 n\n\n### AM09 [data_update] Lines 68 — CI lower bounds\n- **当前**: `$0.19 \\to 0.69 \\to 1.66 \\to 6.70$`\n- **替换**: n=500 CI lower bounds\n\n### AM10 [data_update] Lines 79-82 — Table (permutation) 全部数据\n- **当前**: 4 行 (observed Δ̃, 95% CI, p_Bonf)\n- **替换**: n=500 permutation test 结果（12 个数字）\n\n### AM11 [figure_update] Lines 87-92 — Figure 4 (fig4_bootstrap.pdf)\n- **操作**: 用 n=500 数据重新生成\n\n### AM12 [data_update] Lines 111-122 — Table (discrimination-metrics-full) 全部数据\n- **当前**: 8 行 (ΔGini, ΔCV)\n- **替换**: 若 C4 分析基于 n=500 重跑则更新（16 个数字）\n\n### AM13 [data_update] Lines 137-139 — Entropy delta 描述\n- **当前**: DeepSeek `$\\Delta\\mathcal{H} \\in [-0.047, -0.040]$`, Qwen s025 `$+0.045$`\n- **替换**: 若 C4 分析基于 n=500 重跑则更新\n\n### AM14 [data_update] Lines 149-162 — Table (entropy-deltas) 全部数据\n- **当前**: 8 行\n- **替换**: 若 C4 分析基于 n=500 重跑则更新\n\n---\n\n## Appendix D (appendix_disc_analysis.tex) — Extended Discussion + Limitations\n\n### AD01 [data_update] Line 4 — Random Gini 范围\n- **当前**: `$-0.031$ to $-0.073$; Qwen: $-0.019$ to $-0.045$`\n- **替换**: 若 C4 基于 n=500 重跑则更新\n\n### AD02 [data_update] Line 11 — High-phase II 上限\n- **当前**: `$\\widetilde{\\mathrm{II}}_{\\text{high}} < 0.06$ at $s \\leq 0.30$`; `$s = 0.35$, high-phase II rises to $0.105$`\n- **替换**: n=500 high-phase median II 值\n\n### AD03 [data_update] Line 14 — Random 7/8 统计\n- **当前**: `7/8`, `$p{=}0.012$`, `$d_z{=}{-}0.04$`\n- **替换**: 与 A04 同步\n- **注意**: D059 — 不报 d_z\n\n### AD04 [data_update] Lines 44-47 — 统计范围详情\n- **当前**: `$n{=}49$ ... $n{=}46$`, mean/median ratio `${\\sim}1.6{:}1$`, permutation CI 值\n- **替换**: n=500 统计\n\n### AD05 [data_update] Line 49 — Qwen random s030 例外\n- **当前**: `$p{=}0.012$`, `$d_z{=}{-}0.04$`\n- **替换**: 与 AR03 同步\n- **注意**: D059 — 不报 d_z\n\n### AD06 [data_update] Lines 53-57 — Growth rate 描述\n- **当前**: `$3.8{\\times} \\to 4.8{\\times} \\to 2.0{\\times}$`\n- **替换**: n=500 Δ growth rate\n\n---\n\n## 图表重新生成清单\n\n| # | 文件名 | 数据来源 | 引用位置 |\n|---|--------|----------|----------|\n| F1 | fig1_dose_response.pdf | n=500 DeepSeek imp+rand G vs s | results.tex:57, caption:58 |\n| F2 | fig3_crossover.pdf | n=500 DeepSeek s=0.25 crossover | appendix_moved.tex:15 |\n| F3 | fig4_bootstrap.pdf | n=500 permutation test forest plot | appendix_moved.tex:89 |\n| F4 | fig5_crossmodel.pdf | n=500 DeepSeek+Qwen Δ comparison | appendix_moved.tex:47 |\n| F5 | (unnamed hero figure if separate) | 确认是否与 fig1 相同 | results.tex:57 |\n\n---\n\n## 硬约束合规审查\n\n### HC01 [D054] II 只报 median + median bootstrap CI ✅\n- abstract/results/discussion 全文使用 median ($\\widetilde{\\mathrm{II}}$)\n- methodology.tex:18 提及 mean/median ratio 作为选择 median 的理由 ✓\n- **注意**: n=500 更新时确认所有新数字均为 median\n\n### HC02 [D059] d_z 只报 within-importance ⚠️ 6 处违规\n| 位置 | 当前内容 | 问题 |\n|------|---------|------|\n| abstract.tex:8 | random `$d_z{=}{-}0.04$` | imp-vs-rand d_z |\n| results.tex:79 | LLaMA `$d_z$ ($0.19 \\to 0.34$)` | imp-vs-rand d_z |\n| results.tex:79 | random `$d_z \\in [0.35, 0.45]$` | random d_z |\n| results.tex:88-97 | Table 3 d_z 列 | imp-vs-rand d_z |\n| discussion.tex:11 | `$d_z \\in [0.35, 0.45]$` | random d_z |\n| appendix_disc_analysis.tex:14,49 | `$d_z{=}{-}0.04$` | random d_z |\n\n**修改方案**: 所有 imp-vs-rand 和 random d_z 替换为 Wilcoxon p + median_diff；Table 3 d_z 列替换为 within-importance d_z 或移除\n\n### HC03 [D015] Framing: emergent phase-strategy interaction ✅\n- abstract.tex:4 使用 \"emergent phase-strategy interaction\" ✓\n- 全文无 \"importance is broken\" 叙事 ✓\n\n### HC04 [D056] C5b 已降为 §8 future work ✅\n- discussion.tex:8 讨论 phase-aware budget 作为 implication（未 claim 实现）✓\n- conclusion.tex:5 \"motivate phase-aware sparsity allocation\" ✓\n- **注意**: D056 确认 c5b_pilot gate_failed (oracle 18% < 30%)，论文不应 claim C5b 成功\n\n### HC05 [D060] C8 LLaMA 用 suggests/partial support ✅\n- abstract.tex:10 \"suggests cross-architecture generalization\" ✓\n- discussion.tex:11 \"provides partial support\" ✓\n- conclusion.tex:4 \"partially extends\" ✓\n- results.tex:77-81 \"The qualitative pattern replicates\" — **borderline**，建议改为 \"The qualitative pattern is directionally consistent\"\n\n### HC06 [硬约束 #6] Random 也有正 II，区分信号是 gradient ✅\n- results.tex Table 2 显示 random 有正 II ✓\n- 叙事正确区分：\"compound severity depends qualitatively on eviction strategy\" ✓\n- **注意**: n=500 random 数据可能有不同 pattern，需重新验证此叙事\n\n---\n\n## 按 Section 分布\n\n| Section | 更新点数 |\n|---------|---------|\n| Abstract | 8 |\n| Introduction | 4 |\n| Methodology | 3 |\n| Results | 26 |\n| Analysis | 3 |\n| Discussion | 6 |\n| Conclusion | 6 |\n| Limitations | 2 |\n| Appendix (formulation) | 1 |\n| Appendix (results summary) | 3 |\n| Appendix (moved content) | 14 |\n| Appendix (disc+limitations) | 6 |\n| **Total** | **82** (含重复引用) |\n| **Unique** | **~70** |\n\n---\n\n## 高风险点（可能需要改叙事）\n\n### RISK-1: Qwen s015 是否仍然 non-significant\n- D052 预注册：若 n=500 Qwen s015 仍 ns，叙事改为 \"compound effect emerges above a model-dependent threshold\"\n- D061 已确认 n=500 下 Qwen s015 显著 (p<0.0001)——**如果最终数据确认，此风险解除**\n- 影响范围：abstract, introduction, results §5.4, §5.6, conclusion\n\n### RISK-2: Random PASS/FAIL 模式可能变化\n- n=50 下 7/8 FAIL（Qwen s030 borderline PASS d≈0）\n- n=500 功效更高，可能检测到更多 borderline 显著\n- 影响范围：需重新评估 \"no significant phase modulation\" 叙事\n- D059 保护：不报 random d_z，用 Wilcoxon p + median_diff 更 robust\n\n### RISK-3: LLaMA 数据是否跑 n=500\n- 当前 LLaMA 仅 n=49\n- 若不重跑：DeepSeek/Qwen 倍数比需重算（分母变了）\n- 若重跑：全部 LLaMA 数据需更新\n\n### RISK-4: D059 Table 3 重构\n- Table 3 (llama-cross-arch) 的核心组织方式围绕 imp-vs-rand d_z\n- 删除 d_z 列后需要替代结构，可能影响 §5.5 整段叙事\n\n### RISK-5: Crossover pattern 在 n=500 是否稳定\n- crossover 是论文的一个 key finding\n- n=500 的 crossover 倍数和位置可能变化\n- 影响范围：abstract, results §5.3, discussion, appendix\n\n### RISK-6: C4 entropy 分析是否需要基于 n=500 重跑\n- 当前 C4 降级为 supporting analysis (D045/D046)\n- 若不重跑：analysis.tex 和 appendix 表格保留 n=50 数据，需标注\n- 若重跑：AN01-AN03, AM12-AM14, AD01 全部更新\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
````

</details>

---

### Assistant

_source line 53_

<details><summary>Logged reasoning block</summary>

```text
Now I need to register this artifact. Let me check how to register artifacts.

Looking at the CLAUDE.md: "产出目录：`/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/`（写文件后用 `register_artifact` 注册）"

Let me search for the register_artifact tool.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "6bba340f-03b0-4988-baa7-107220f3bf70",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01F6LbV7w4nUoQnGvPQhzC8o",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10762,
      "cache_read_input_tokens": 75294,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10762
      },
      "output_tokens": 9,
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

_source line 54_

清单已写入。注册 artifact。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "7f846c85-f92a-41a0-bb5d-6dce7cdb4171",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01F6LbV7w4nUoQnGvPQhzC8o",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10762,
      "cache_read_input_tokens": 75294,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10762
      },
      "output_tokens": 9,
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

_source line 55_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01QFH2zoMR9QzQHJCVFmv3Ae`</summary>

```json
{
  "query": "register artifact",
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
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "21fffe7d-5b38-4a02-a264-d8aa524ae611",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01F6LbV7w4nUoQnGvPQhzC8o",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10762,
      "cache_read_input_tokens": 75294,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10762
      },
      "output_tokens": 9,
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

_source line 56 · 2026-05-14T20:49:01.407Z_

<details><summary>↩ Tool result · `toolu_01QFH2zoMR9QzQHJCVFmv3Ae`</summary>

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
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "0961ae10-20f2-42ef-b5e5-576386b77059",
  "tool_use_result": {
    "matches": [],
    "query": "register artifact",
    "total_deferred_tools": 26
  }
}
```

</details>

---

### Runtime record

_source line 57_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed_warning",
    "resetsAt": 1778911200,
    "rateLimitType": "seven_day",
    "utilization": 0.84,
    "isUsingOverage": false,
    "surpassedThreshold": 0.75
  },
  "uuid": "98c88f48-66ef-4e4f-9390-f8ef5144221b",
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9"
}
```

---

### Tool call

_source line 58_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01Kmsir5xp67srVckaZsqgFU`</summary>

```json
{
  "query": "register",
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
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "5142c802-80bd-40fe-9566-e68c689efff6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Jq99KBiYUEvfiYCJNAbiLc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 211,
      "cache_read_input_tokens": 86056,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 211
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

_source line 59 · 2026-05-14T20:49:03.917Z_

<details><summary>↩ Tool result · `toolu_01Kmsir5xp67srVckaZsqgFU`</summary>

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
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "6d43f433-3e16-4c05-be5b-091ee78e5c8c",
  "tool_use_result": {
    "matches": [],
    "query": "register",
    "total_deferred_tools": 26
  }
}
```

</details>

---

### Tool call

_source line 60_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01LiP8nM8jh4W5cC6ya1QLWd`</summary>

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
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "f16efb18-2ac4-4f0c-a9b6-643f7821b59a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LtVsSSo65piwqyz5itK35x",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 90,
      "cache_read_input_tokens": 86267,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 90
      },
      "output_tokens": 72,
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

_source line 61 · 2026-05-14T20:49:06.444Z_

<details><summary>↩ Tool result · `toolu_01LiP8nM8jh4W5cC6ya1QLWd`</summary>

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
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "fe07d6d8-a0c1-4295-8d75-aed6051c41c2",
  "tool_use_result": {
    "matches": [],
    "query": "artifact",
    "total_deferred_tools": 26
  }
}
```

</details>

---

### Assistant

_source line 62_

<details><summary>Logged reasoning block</summary>

```text
There's no register_artifact tool available. The artifact file has been written to the artifacts directory. Let me just report the results.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "9973a48d-9737-4e75-a648-298a68f9d382",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016uoGTCrpY7sEWS1t1Vjsze",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 193,
      "cache_read_input_tokens": 86357,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 193
      },
      "output_tokens": 9,
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

_source line 63_

清单已产出至 `artifacts/n500_update_checklist.md`。

## 汇总

**更新点总数**：70 个（去重后），82 处引用（含跨 section 重复）

**按 section 分布**：
- Results (§5)：**26 处**（最密集——4 张表 + 1 张图 + 所有定量声明）
- Appendix (moved content)：14 处
- Abstract：8 处
- Discussion/Conclusion：12 处
- 其余 section：12 处

**图表需重新生成**：5 张（fig1_dose_response, fig3_crossover, fig4_bootstrap, fig5_crossmodel + 确认是否有额外 hero figure）

**硬约束合规**：
- D054 (median only) ✅
- D015 (emergent interaction framing) ✅
- D056 (C5b→future work) ✅
- D060 (LLaMA→suggests) ✅，但 results.tex:77 "The qualitative pattern replicates" 建议软化
- **D059 违规 ⚠️ 6 处**：abstract/results/discussion/appendix 中有 imp-vs-rand d_z 和 random d_z，需全部替换为 Wilcoxon p + median_diff。Table 3 (llama-cross-arch) 需要结构重构

**高风险点**：
1. Qwen s015 显著性——D061 显示 n=500 已显著，风险解除
2. Random PASS/FAIL 模式可能因 n=500 功效提升而变化
3. LLaMA 是否跑 n=500（决定 §5.5 全部数据是否更新）
4. Table 3 重构（D059 违规修复涉及整段叙事）
5. Crossover pattern 稳定性
6. C4 entropy 分析是否基于 n=500 重跑（影响 §6 + appendix 2 张表）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "uuid": "ec2460b0-13a2-4138-acd5-aeb0ec3fea0a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016uoGTCrpY7sEWS1t1Vjsze",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 193,
      "cache_read_input_tokens": 86357,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 193
      },
      "output_tokens": 9,
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

_source line 64_

清单已产出至 `artifacts/n500_update_checklist.md`。

## 汇总

**更新点总数**：70 个（去重后），82 处引用（含跨 section 重复）

**按 section 分布**：
- Results (§5)：**26 处**（最密集——4 张表 + 1 张图 + 所有定量声明）
- Appendix (moved content)：14 处
- Abstract：8 处
- Discussion/Conclusion：12 处
- 其余 section：12 处

**图表需重新生成**：5 张（fig1_dose_response, fig3_crossover, fig4_bootstrap, fig5_crossmodel + 确认是否有额外 hero figure）

**硬约束合规**：
- D054 (median only) ✅
- D015 (emergent interaction framing) ✅
- D056 (C5b→future work) ✅
- D060 (LLaMA→suggests) ✅，但 results.tex:77 "The qualitative pattern replicates" 建议软化
- **D059 违规 ⚠️ 6 处**：abstract/results/discussion/appendix 中有 imp-vs-rand d_z 和 random d_z，需全部替换为 Wilcoxon p + median_diff。Table 3 (llama-cross-arch) 需要结构重构

**高风险点**：
1. Qwen s015 显著性——D061 显示 n=500 已显著，风险解除
2. Random PASS/FAIL 模式可能因 n=500 功效提升而变化
3. LLaMA 是否跑 n=500（决定 §5.5 全部数据是否更新）
4. Table 3 重构（D059 违规修复涉及整段叙事）
5. Crossover pattern 稳定性
6. C4 entropy 分析是否基于 n=500 重跑（影响 §6 + appendix 2 张表）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 338523,
  "duration_api_ms": 339391,
  "num_turns": 24,
  "stop_reason": "end_turn",
  "session_id": "9852c07f-83d4-45d5-a6c2-924f3fb8d8e9",
  "total_cost_usd": 1.2443235000000001,
  "usage": {
    "input_tokens": 15,
    "cache_creation_input_tokens": 88498,
    "cache_read_input_tokens": 477960,
    "output_tokens": 18028,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 88498,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 599,
        "cache_read_input_tokens": 86357,
        "cache_creation_input_tokens": 193,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 193
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1361,
      "outputTokens": 19,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.001456,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 15,
      "outputTokens": 18028,
      "cacheReadInputTokens": 477960,
      "cacheCreationInputTokens": 88498,
      "webSearchRequests": 0,
      "costUSD": 1.2428675,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "b9ccfb32-f137-4340-9679-18d558613bfc"
}
```

</details>

---
