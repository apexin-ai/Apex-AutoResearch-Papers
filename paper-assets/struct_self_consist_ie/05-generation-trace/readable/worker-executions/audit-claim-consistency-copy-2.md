# audit claim consistency

**When Self-Consistency Fails for NER: Degeneracy, Signal Collapse, and the Correlation-Selection Gap** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 101
- **Recorded user turns:** 0
- **Tool calls:** 41
- **Original source:** `logs/workers/worker_audit_claim_consistency_20260518T054521.log`
- **Structured JSON:** [`52de5a7bc967f7264158.json`](../../sessions/52/52de5a7bc967f7264158.json)

## Before a recorded user message

101 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie",
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
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
  "uuid": "12657e54-20f4-4d5d-85b3-b62fb3e41d7a",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/memory/"
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
    "resetsAt": 1779100800,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "f77eb7bf-8195-44c8-9750-be0317024350",
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me start by finding all the .tex files in the project directory.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "5e7abc85-9d3b-480e-b600-c1c082692b1c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0178tu59WV3hrN3VyGMiqHpt",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13553,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13553
      },
      "output_tokens": 32,
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

开始全文数值一致性审计。先定位论文 tex 文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "9c8491c3-45ec-4612-822a-f616408faa92",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0178tu59WV3hrN3VyGMiqHpt",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13553,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13553
      },
      "output_tokens": 32,
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

<details open><summary>🔧 Tool call — Bash · `toolu_01NN21s3t2295gYv6xsBjwdj`</summary>

```json
{
  "command": "find /home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/ -name \"*.tex\" 2>/dev/null | head -30",
  "description": "Find all .tex files in the project"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "95781abf-3145-4975-a35a-e46ed740523a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0178tu59WV3hrN3VyGMiqHpt",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13553,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13553
      },
      "output_tokens": 32,
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

_source line 7 · 2026-05-18T05:45:32.640Z_

<details><summary>↩ Tool result · `toolu_01NN21s3t2295gYv6xsBjwdj`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/abstract.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/n_scaling_appendix_tables_44b000.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/n_scaling_appendix_tables.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/abstract.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/limitations.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/discussion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/freeform_ablation_appendix_table.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/experiments.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/bootstrap_ci_tables.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/n_scaling_appendix_tables.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260516T092241/median/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260516T092241/worst/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260516T092241/best/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260514T203201/median/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260514T203201/worst/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260514T203201/best/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260516T113255/median/paper.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "8642dac2-c7d6-42d7-87c3-e27264ab59d3",
  "tool_use_result": {
    "stdout": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/abstract.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/conclusion.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/related_work.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/main.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/introduction.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/n_scaling_appendix_tables_44b000.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/n_scaling_appendix_tables.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/abstract.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/limitations.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/method.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/discussion.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/conclusion.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/freeform_ablation_appendix_table.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/experiments.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper/related_work.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/bootstrap_ci_tables.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/n_scaling_appendix_tables.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260516T092241/median/paper.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260516T092241/worst/paper.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260516T092241/best/paper.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260514T203201/median/paper.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260514T203201/worst/paper.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260514T203201/best/paper.tex\n/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/dream_reports/dream_20260516T113255/median/paper.tex",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 8_

论文在 `docs/paper/sections/` 下。按照 C001 约束，只审计这个目录。现在并行读取所有 tex 文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "b416b250-426f-4b35-8fb0-fc2c3460a47b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KioYcRTqz3d75hQTPrqcXj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1498,
      "cache_read_input_tokens": 25394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1498
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

_source line 9_

<details open><summary>🔧 Tool call — Read · `toolu_017LwUePKahUygYTXF22cKzA`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "c0fe0a06-dc42-468a-a544-6a46ffd3ca82",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KioYcRTqz3d75hQTPrqcXj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1498,
      "cache_read_input_tokens": 25394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1498
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

_source line 10 · 2026-05-18T05:45:36.193Z_

<details><summary>↩ Tool result · `toolu_017LwUePKahUygYTXF22cKzA`</summary>

```text
1	\begin{abstract}
2	Self-consistency yields large gains on discrete-answer tasks, but named entity recognition (NER) produces \textit{sets} of entities with partial overlap, where no majority vote analog exists.
3	We evaluate five confidence signals (four instance-level, one per-sample log-probability [LP]) for quality estimation and sample selection on four NER benchmarks using 4B\textendash 8B models.
4	All signals achieve reliable quality estimation ($\rho$ up to 0.42, AUROC up to 0.82), supporting selective prediction.
5	For selection, LP achieves $+1.36$~pp on Few-NERD ($p{<}0.001$) under two jointly necessary conditions: low instance degeneracy and adequate LP-quality alignment ($\rho \gtrsim 0.3$).
6	When either condition is violated, LP gains fall below detectable thresholds despite ${\sim}$13~pp oracle headroom, a disparity we term the \textbf{correlation-selection gap}.
7	Two mechanisms explain this gap: \textit{instance degeneracy} (14\textendash 59\% of instances yield identical F1 scores across all samples) eliminates headroom; \textit{weak LP-quality alignment} prevents exploiting the remainder.
8	A methodological premise underlies both: four of five signals are instance-level aggregates that by definition cannot rank candidates.
9	Degeneracy is controllable via temperature and training convergence; closing the gap for structural signals likely requires learned per-sample scoring.
10	\end{abstract}
11	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "901d27e5-f2b7-4968-a1de-251ec8ffcd6d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/abstract.tex",
      "content": "\\begin{abstract}\nSelf-consistency yields large gains on discrete-answer tasks, but named entity recognition (NER) produces \\textit{sets} of entities with partial overlap, where no majority vote analog exists.\nWe evaluate five confidence signals (four instance-level, one per-sample log-probability [LP]) for quality estimation and sample selection on four NER benchmarks using 4B\\textendash 8B models.\nAll signals achieve reliable quality estimation ($\\rho$ up to 0.42, AUROC up to 0.82), supporting selective prediction.\nFor selection, LP achieves $+1.36$~pp on Few-NERD ($p{<}0.001$) under two jointly necessary conditions: low instance degeneracy and adequate LP-quality alignment ($\\rho \\gtrsim 0.3$).\nWhen either condition is violated, LP gains fall below detectable thresholds despite ${\\sim}$13~pp oracle headroom, a disparity we term the \\textbf{correlation-selection gap}.\nTwo mechanisms explain this gap: \\textit{instance degeneracy} (14\\textendash 59\\% of instances yield identical F1 scores across all samples) eliminates headroom; \\textit{weak LP-quality alignment} prevents exploiting the remainder.\nA methodological premise underlies both: four of five signals are instance-level aggregates that by definition cannot rank candidates.\nDegeneracy is controllable via temperature and training convergence; closing the gap for structural signals likely requires learned per-sample scoring.\n\\end{abstract}\n",
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

_source line 11_

<details open><summary>🔧 Tool call — Read · `toolu_01FWHfj5KZpt65RXhVJdKr98`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "63df2736-50d5-47e2-b007-00cbcc313062",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KioYcRTqz3d75hQTPrqcXj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1498,
      "cache_read_input_tokens": 25394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1498
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

_source line 12 · 2026-05-18T05:45:36.662Z_

<details><summary>↩ Tool result · `toolu_01FWHfj5KZpt65RXhVJdKr98`</summary>

```text
1	\section{Introduction}\label{sec:introduction}
2	
3	Self-consistency (majority voting over multiple samples) yields large gains on discrete-answer reasoning \citep{wang2023selfconsistency}, and test-time compute scaling has emerged as a complementary axis to model scaling \cite{snell2025scaling, brown2024monkeys}.
4	But named entity recognition (NER) poses a structurally different challenge: the output is a \textit{set} of entities, two samples may extract overlapping but non-identical sets, and there is no obvious majority to vote on.
5	
6	Prior work on confidence estimation for LLM-based IE has conflated \textit{quality estimation} (which inputs does the model handle reliably?) with \textit{sample selection} (which of $N$ outputs is best?).
7	Existing self-consistency methods \cite{wang2023selfconsistency, chen2024usc, taubenfeld2025cisc, kang2025selfcertainty} assume outputs can be grouped by equivalence, an assumption that breaks for entity sets with partial overlap.
8	Unlike \citet{yao2026consistency}, who demonstrate that self-consistency correlates with task accuracy, we investigate \textit{why} this correlation does not reliably translate to selection gains, diagnosing degeneracy and compression as the two blocking mechanisms.
9	Our experiments use fine-tuned models, the dominant deployment paradigm for production NER, and separate quality estimation from best-of-$N$ selection.
10	
11	A methodological premise structures our analysis: four of five signals (SJ, VC, FK, EM) are instance-level aggregates that by design assign identical scores to all $N$ candidates for a given input; only log-probability (LP) is natively per-sample.
12	All signals achieve reliable quality estimation ($\rho$ up to 0.42, AUROC up to 0.82; Figure~\ref{fig:overview}), supporting selective prediction.
13	For selection, LP achieves $+1.36$~pp on Few-NERD ($p{<}0.001$) when two conditions are jointly met: low instance degeneracy (13.8\%) and adequate alignment ($\rho{\approx}0.5$), with gains scaling with $N$ ($+0.52$~pp, $p{=}0.003$).
14	On SciERC, the observed LP gain ($+0.2$~pp, $p{=}0.29$) falls below the minimum detectable effect (${\approx}$1.5~pp at 80\% power, $n{=}529$) despite 13~pp oracle headroom. We term this disparity between quality estimation strength and selection effectiveness the \textbf{correlation-selection gap}.
15	Two mechanisms explain this gap: (a)~\textit{instance degeneracy} (14\textendash 59\% of instances yield identical F1 scores across all $N$ samples, eliminating headroom); and (b)~\textit{weak LP-quality alignment} (within-instance $\rho(\text{LP}, \text{F1})$ too low to exploit the remaining headroom; \S\ref{sec:discussion}).
16	
17	\begin{figure*}[t]
18	\centering
19	\includegraphics[width=\textwidth]{fig_overview}
20	\caption{The correlation-selection gap. \textbf{Left}: consistency signals reliably predict instance-level quality ($\rho$ up to 0.45 on CoNLL, 0.38 on the primary test bed, 0.42 on Few-NERD; AUROC up to 0.82). \textbf{Right}: quality estimation does not translate to selection; all methods approximately match greedy decoding ($T{=}0$) despite 13~pp oracle headroom (\S\ref{sec:discussion}).}
21	\label{fig:overview}
22	\end{figure*}
23	
24	We evaluate five signals from three families (structural, surface, and model-internal) on SciERC \cite{luan2018scierc} as a primary medium-difficulty test bed, with Few-NERD \cite{ding2021fewnerd} (low-degeneracy contrast), CoNLL-2003 \cite{tjongkimsang2003conll} (ceiling-effect control), and WNUT-17 \cite{derczynski2017wnut} (signal-collapse boundary), using two 8B models (Qwen3-8B, LLaMA-3.1-8B) with a 4B ablation (Qwen3-4B).
25	We vary candidate pool size ($N{\in}\{2,\ldots,32\}$), signal sophistication, and model capacity within the 4B\textendash 8B range; behavior at 70B+ scales remains an open question.
26	An exploratory extension to relation extraction is reported in Appendix~\ref{app:re_extension}.
27	Our contributions:
28	\begin{enumerate}
29	    \item \textbf{Quality estimation framework and a methodological premise.}
30	    Five signals from three families evaluated on four NER benchmarks, two model families, and a 4B ablation, achieving reliable quality estimation ($\rho$ up to 0.42; AUROC up to 0.82).
31	    A definitional observation structures the analysis: four of five signals are instance-level aggregates that by design assign identical scores to all candidates; this per-sample vs.\ instance-level distinction determines which signals can, in principle, improve selection.
32	
33	    \item \textbf{Two empirical mechanisms underlying the correlation-selection gap.}
34	    Instance degeneracy (14\textendash 59\% of instances yield identical F1 scores across all samples) eliminates headroom for consensus-based selection; weak LP-quality alignment (within-instance $\rho{\approx}0.24$ on SciERC) prevents exploiting the remaining headroom.
35	    Temperature ablation provides the primary evidence that both conditions are independently necessary ($T{=}1.2$: degeneracy 12.5\%, alignment $\rho{=}0.225$; \S\ref{sec:discussion}); LoRA-rank, entity-token LP, and supervised combination of the five signals studied corroborate the pattern.
36	
37	    \item \textbf{Practical conditions for LP selection.}
38	    LP achieves $+1.36$~pp on Few-NERD ($p{<}0.001$) and scales with $N$ ($+0.52$~pp, $p{=}0.003$) when degeneracy ${<}$15\% and alignment $\rho \gtrsim 0.3$.
39	    Per-entity-type analysis within Few-NERD ($\rho{=}{-}0.881$, $p{=}0.004$, $n{=}8$; types share model and tokenizer, so effective degrees of freedom may be lower) provides supporting evidence; temperature and training convergence offer controllable levers for degeneracy.
40	\end{enumerate}
41	
42	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "d1be8b99-2aad-4c0c-86ad-b1356dd0926e",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex",
      "content": "\\section{Introduction}\\label{sec:introduction}\n\nSelf-consistency (majority voting over multiple samples) yields large gains on discrete-answer reasoning \\citep{wang2023selfconsistency}, and test-time compute scaling has emerged as a complementary axis to model scaling \\cite{snell2025scaling, brown2024monkeys}.\nBut named entity recognition (NER) poses a structurally different challenge: the output is a \\textit{set} of entities, two samples may extract overlapping but non-identical sets, and there is no obvious majority to vote on.\n\nPrior work on confidence estimation for LLM-based IE has conflated \\textit{quality estimation} (which inputs does the model handle reliably?) with \\textit{sample selection} (which of $N$ outputs is best?).\nExisting self-consistency methods \\cite{wang2023selfconsistency, chen2024usc, taubenfeld2025cisc, kang2025selfcertainty} assume outputs can be grouped by equivalence, an assumption that breaks for entity sets with partial overlap.\nUnlike \\citet{yao2026consistency}, who demonstrate that self-consistency correlates with task accuracy, we investigate \\textit{why} this correlation does not reliably translate to selection gains, diagnosing degeneracy and compression as the two blocking mechanisms.\nOur experiments use fine-tuned models, the dominant deployment paradigm for production NER, and separate quality estimation from best-of-$N$ selection.\n\nA methodological premise structures our analysis: four of five signals (SJ, VC, FK, EM) are instance-level aggregates that by design assign identical scores to all $N$ candidates for a given input; only log-probability (LP) is natively per-sample.\nAll signals achieve reliable quality estimation ($\\rho$ up to 0.42, AUROC up to 0.82; Figure~\\ref{fig:overview}), supporting selective prediction.\nFor selection, LP achieves $+1.36$~pp on Few-NERD ($p{<}0.001$) when two conditions are jointly met: low instance degeneracy (13.8\\%) and adequate alignment ($\\rho{\\approx}0.5$), with gains scaling with $N$ ($+0.52$~pp, $p{=}0.003$).\nOn SciERC, the observed LP gain ($+0.2$~pp, $p{=}0.29$) falls below the minimum detectable effect (${\\approx}$1.5~pp at 80\\% power, $n{=}529$) despite 13~pp oracle headroom. We term this disparity between quality estimation strength and selection effectiveness the \\textbf{correlation-selection gap}.\nTwo mechanisms explain this gap: (a)~\\textit{instance degeneracy} (14\\textendash 59\\% of instances yield identical F1 scores across all $N$ samples, eliminating headroom); and (b)~\\textit{weak LP-quality alignment} (within-instance $\\rho(\\text{LP}, \\text{F1})$ too low to exploit the remaining headroom; \\S\\ref{sec:discussion}).\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_overview}\n\\caption{The correlation-selection gap. \\textbf{Left}: consistency signals reliably predict instance-level quality ($\\rho$ up to 0.45 on CoNLL, 0.38 on the primary test bed, 0.42 on Few-NERD; AUROC up to 0.82). \\textbf{Right}: quality estimation does not translate to selection; all methods approximately match greedy decoding ($T{=}0$) despite 13~pp oracle headroom (\\S\\ref{sec:discussion}).}\n\\label{fig:overview}\n\\end{figure*}\n\nWe evaluate five signals from three families (structural, surface, and model-internal) on SciERC \\cite{luan2018scierc} as a primary medium-difficulty test bed, with Few-NERD \\cite{ding2021fewnerd} (low-degeneracy contrast), CoNLL-2003 \\cite{tjongkimsang2003conll} (ceiling-effect control), and WNUT-17 \\cite{derczynski2017wnut} (signal-collapse boundary), using two 8B models (Qwen3-8B, LLaMA-3.1-8B) with a 4B ablation (Qwen3-4B).\nWe vary candidate pool size ($N{\\in}\\{2,\\ldots,32\\}$), signal sophistication, and model capacity within the 4B\\textendash 8B range; behavior at 70B+ scales remains an open question.\nAn exploratory extension to relation extraction is reported in Appendix~\\ref{app:re_extension}.\nOur contributions:\n\\begin{enumerate}\n    \\item \\textbf{Quality estimation framework and a methodological premise.}\n    Five signals from three families evaluated on four NER benchmarks, two model families, and a 4B ablation, achieving reliable quality estimation ($\\rho$ up to 0.42; AUROC up to 0.82).\n    A definitional observation structures the analysis: four of five signals are instance-level aggregates that by design assign identical scores to all candidates; this per-sample vs.\\ instance-level distinction determines which signals can, in principle, improve selection.\n\n    \\item \\textbf{Two empirical mechanisms underlying the correlation-selection gap.}\n    Instance degeneracy (14\\textendash 59\\% of instances yield identical F1 scores across all samples) eliminates headroom for consensus-based selection; weak LP-quality alignment (within-instance $\\rho{\\approx}0.24$ on SciERC) prevents exploiting the remaining headroom.\n    Temperature ablation provides the primary evidence that both conditions are independently necessary ($T{=}1.2$: degeneracy 12.5\\%, alignment $\\rho{=}0.225$; \\S\\ref{sec:discussion}); LoRA-rank, entity-token LP, and supervised combination of the five signals studied corroborate the pattern.\n\n    \\item \\textbf{Practical conditions for LP selection.}\n    LP achieves $+1.36$~pp on Few-NERD ($p{<}0.001$) and scales with $N$ ($+0.52$~pp, $p{=}0.003$) when degeneracy ${<}$15\\% and alignment $\\rho \\gtrsim 0.3$.\n    Per-entity-type analysis within Few-NERD ($\\rho{=}{-}0.881$, $p{=}0.004$, $n{=}8$; types share model and tokenizer, so effective degrees of freedom may be lower) provides supporting evidence; temperature and training convergence offer controllable levers for degeneracy.\n\\end{enumerate}\n\n",
      "numLines": 42,
      "startLine": 1,
      "totalLines": 42
    }
  }
}
```

</details>

---

### Tool call

_source line 13_

<details open><summary>🔧 Tool call — Read · `toolu_01L96hDsSsotntSrUWkR8ySr`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "50d43135-b0cc-473c-939a-b34652a25982",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KioYcRTqz3d75hQTPrqcXj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1498,
      "cache_read_input_tokens": 25394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1498
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

_source line 14 · 2026-05-18T05:45:37.602Z_

<details><summary>↩ Tool result · `toolu_01L96hDsSsotntSrUWkR8ySr`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Experimental Setup}
5	\label{sec:setup}
6	
7	\paragraph{Datasets.}
8	We evaluate on four English NER benchmarks spanning a difficulty gradient, each serving a distinct role.
9	\textbf{SciERC} \cite{luan2018scierc} (551 test instances, 6 entity types) is the primary medium-difficulty test bed where models achieve ${\approx}$65\% F1.
10	\textbf{Few-NERD} \cite{ding2021fewnerd} (INTRA coarse; 37{,}648 instances, 8 entity types, ${\approx}$75\% F1) provides a low-degeneracy contrast where LP selection succeeds (\S\ref{sec:fewnerd}).
11	\textbf{CoNLL-2003} \cite{tjongkimsang2003conll} (3{,}453 test sentences, 4 entity types, ${\approx}$91\% F1) serves as a ceiling-effect control where limited oracle headroom constrains selection gains.
12	\textbf{WNUT-17} \cite{derczynski2017wnut} (1{,}287 social media instances, 52\% zero F1) probes the signal-collapse boundary where model capability is insufficient.
13	
14	\paragraph{Models and sampling.}
15	Both \textbf{Qwen3-8B} and \textbf{LLaMA-3.1-8B-Instruct} are fine-tuned with LoRA (rank$=$32, $\alpha{=}64$) for 5 epochs using LLaMA Factory \cite{zheng2024llamafactory} under identical training procedures, except Few-NERD models which use 3 epochs (early stopping at the best validation checkpoint; a 5-epoch control confirms LP selection remains positive though gains are halved; Appendix~\ref{app:epoch_confound}).
16	Qwen3-8B's SciERC checkpoint has a minor train--test mismatch (empty thinking tokens); a quantitative analysis rules out this confound (Appendix~\ref{app:thinking_token}).
17	We draw $N{=}8$ samples at $T{=}1.0$ (primary), with $N{=}16$ for scaling experiments.\footnote{$N{=}16$ with 3 seeds verifies scaling and ranking stability ($\sigma{\leq}0.026$; Table~\ref{tab:multiseed}); gains beyond $N{=}8$ are sublinear (Appendix~\ref{app:n_scaling}).}
18	Inference uses vLLM with constrained decoding \cite{willard2023guided}.\footnote{Quality estimation uses a single primary seed (seed${=}42$); selection uses 2-seed averages for variance estimation. Three-seed experiments ($\sigma{\leq}0.026$; Table~\ref{tab:multiseed}) confirm ranking stability; the reduced seed count for primary results reflects computational budget.}
19	
20	%% ============================================================
21	\subsection{Quality Estimation Results}
22	\label{sec:qe_results}
23	
24	\begin{table*}[t]
25	\centering
26	\small
27	\caption{NER quality estimation ($\rho$ and AUROC; $N{=}8$, primary seed${=}42$; 3-seed stability $\sigma{\leq}0.026$ in Table~\ref{tab:multiseed}). Best in \textbf{bold}. RE results in Appendix~\ref{app:re_extension}. $N{=}16$ in Table~\ref{tab:robustness}.}
28	\label{tab:quality_estimation}
29	\begin{tabular}{ll cc cc cc}
30	\toprule
31	& & \multicolumn{2}{c}{\textbf{SciERC}} & \multicolumn{2}{c}{\textbf{CoNLL (Qwen)}} & \multicolumn{2}{c}{\textbf{CoNLL (LLaMA)}} \\
32	\cmidrule(lr){3-4} \cmidrule(lr){5-6} \cmidrule(lr){7-8}
33	Signal & Family & $\rho$ & AUC & $\rho$ & AUC & $\rho$ & AUC \\
34	\midrule
35	VC & Structural & \textbf{.379} & \textbf{.663} & .424 & .789 & .426 & .709 \\
36	SJ  & Structural & .360 & .650 & .436 & .801 & \textbf{.431} & .704 \\
37	FK & Surface & .267 & .602 & .400 & .774 & .428 & .703 \\
38	EM  & Surface    & .295 & .614 & \textbf{.451} & \textbf{.816} & \textbf{.431} & .705 \\
39	\midrule
40	LP     & Model      & .205 & .578 & .316 & .753 & .307 & \textbf{.761} \\
41	\bottomrule
42	\end{tabular}
43	\end{table*}
44	
45	Table~\ref{tab:quality_estimation} presents $\rho$ and AUROC for five signals across tasks and models.\footnote{$\varepsilon{=}0.05$ applies only to selection (\S\ref{sec:selection_gap}); quality estimation is $\varepsilon$-free. Selection F1 is stable across $\varepsilon \in [0, 0.2]$ (Appendix~\ref{app:epsilon_robustness}).}
46	
47	\paragraph{Signal rankings are difficulty-dependent.}
48	On SciERC (medium difficulty), structural signals lead (VC $\rho{=}0.379$, SJ $0.360$) over LP ($0.205$); bootstrap CIs confirm the gap ($\Delta\rho{=}{+}0.155$; Appendix~\ref{app:bootstrap_signal}).
49	On CoNLL (single-sample F1${\approx}$0.91), EM leads both $\rho$ and AUROC ($0.816$).
50	At the signal-collapse boundary (WNUT-17, macro F1${\approx}$42\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\rho{=}0.724$ but conditional $\rho{=}0.038$; Table~\ref{tab:wnut}); LP shows the reverse (conditional $\rho{=}0.350$; Figure~\ref{fig:signal_heatmap}).
51	
52	%% ============================================================
53	\subsection{The Correlation-Selection Gap}
54	\label{sec:selection_gap}
55	
56	Two mechanisms block selection: instance degeneracy collapses the candidate pool for consensus-based approaches, and weak LP-quality alignment prevents exploiting the remaining headroom.
57	A methodological observation underlies both: four instance-level signals cannot rank candidates by construction; LP requires both low degeneracy and adequate alignment ($\rho \gtrsim 0.3$).
58	
59	\begin{table}[t]
60	\centering
61	\small
62	\caption{Best-of-$N$ NER selection (macro F1) on SciERC ($N{=}8$, $T{=}1.0$, 2-seed mean${\pm}\sigma$). LP is per-sample; others use consensus-proximity. Best non-oracle in \textbf{bold}. Non-tied subset in \S\ref{sec:discussion}; RE in Appendix~\ref{app:re_extension}.}
63	\label{tab:selection}
64	\begin{tabular}{lcc}
65	\toprule
66	Method & NER F1 & $p$ \\
67	\midrule
68	Oracle & $0.778 \pm 0.003$ & --- \\
69	Greedy ($T{=}0$) & $0.645 \pm 0.001$ & --- \\
70	\midrule
71	\multicolumn{3}{l}{\textit{Per-sample signal}} \\
72	LP           & $\mathbf{0.647} \pm 0.005$ & .29 \\
73	\midrule
74	\multicolumn{3}{l}{\textit{Instance-level signals (consensus-proximity selection)}} \\
75	SJ           & $0.646 \pm 0.002$ & .67 \\
76	FK           & $0.646 \pm 0.001$ & .79 \\
77	EM           & $0.637 \pm 0.001$ & --- \\
78	VC           & $0.623 \pm 0.004$ & --- \\
79	\midrule
80	Random           & $0.610 \pm 0.003$ & --- \\
81	\bottomrule
82	\end{tabular}
83	\end{table}
84	
85	Despite moderate quality estimation, no signal consistently improves selection over greedy (Table~\ref{tab:selection}).
86	Instance-level signals assign identical QE scores to all candidates; MBR conversion does not improve over greedy on the primary test bed.
87	
88	\paragraph{No significant improvement over greedy.}
89	On SciERC ($n{=}529$, 2-seed sign tests\footnote{Seed variation $\sigma{\leq}0.026$ (Table~\ref{tab:multiseed}); MDE${\approx}$1.5~pp at 80\% power for $n{=}529$, so a 1~pp effect yields only ${\sim}$55\% power. Few-NERD ($n{=}32{,}565$; MDE${\approx}$0.22~pp) provides the definitive test.}), the oracle (0.778) reveals 13.3~pp of headroom, but LP achieves $+0.2$~pp ($p{=}0.29$), below the MDE (${\approx}$1.5~pp).
90	The pattern holds across CoNLL and WNUT-17 (Table~\ref{tab:cross_selection}); under stringent TOST anchors, some configurations show significant \textit{degradation} (Appendix~\ref{app:tost}).
91	Few-NERD provides the definitive contrast: LP achieves $+1.36$~pp ($p{<}0.001$) at low degeneracy (\S\ref{sec:fewnerd}), while structural signals still degrade selection.
92	Instance-level signals predict \textit{which inputs} the model handles reliably, not \textit{which output} is best; closing this gap likely requires trained verifiers \cite{cobbe2021verifiers}.\footnote{The sole positive finding (non-tied LP subset, $+2.9$~pp, $p{=}0.004$; \S\ref{sec:discussion}) survives Bonferroni correction over 5 comparisons.}
93	
94	%% ============================================================
95	\subsection{Cross-Dataset Contrast: Few-NERD}
96	\label{sec:fewnerd}
97	
98	\begin{table}[t]
99	\centering
100	\small
101	\caption{Cross-dataset comparison of LP selection effectiveness (Qwen3-8B, $N{=}8$, $T{=}1.0$, gold-filtered). LP $\rho$: Spearman correlation between max token-level log-probability and instance F1. LP selection gains are inversely associated with instance degeneracy.\protect\footnotemark\protect\footnotemark}
102	\label{tab:fewnerd}
103	\begin{tabular}{lcccccc}
104	\toprule
105	Dataset & $n$ & Greedy & Headroom & Degen\% & LP $\rho$ & LP $\Delta$ \\
106	\midrule
107	CoNLL & 2{,}756 & .908 & 4.0\,pp & 59.1\% & .302 & $-$1.05\,pp \\
108	SciERC & 529 & .644 & 13.2\,pp & 17.8\% & .215 & $+$0.61\,pp \\
109	Few-NERD & 32{,}565 & .748 & 12.4\,pp & 13.8\% & .421 & $\mathbf{+1.36}$\,pp \\
110	\bottomrule
111	\end{tabular}
112	\end{table}
113	\footnotetext{SciERC values (greedy${=}0.644$, headroom${=}13.2$~pp) differ slightly from Table~\ref{tab:selection} (greedy${=}0.645$, headroom${=}13.3$~pp) due to max-LP aggregation and single-seed evaluation; the ranking is unchanged.}
114	\footnotetext{Instance degeneracy: fraction of gold-filtered instances where all $N$ samples produce identical instance-level F1.}
115	
116	Few-NERD (Table~\ref{tab:fewnerd}) confirms that LP selection effectiveness is inversely associated with degeneracy.
117	Under standard early stopping, Few-NERD degeneracy is 13.8\% (training convergence modulates this rate, Appendix~\ref{app:epoch_confound}), and LP achieves $+1.36$~pp (95\% CI $[+1.18, +1.53]$, $p{<}0.001$), while all structural signals degrade selection (VC $-1.79$, SJ $-2.14$~pp).
118	
119	\paragraph{Two necessary conditions for LP selection.}
120	The cross-dataset gradient is consistent with an inverse relationship (59.1\% $\to$ $-1.05$~pp, 17.8\% $\to$ $+0.61$~pp, 13.8\% $\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory given 5+ confounds; Figure~\ref{fig:degeneracy_scatter}), with supporting evidence from per-entity-type analysis within Few-NERD ($n{=}8$, $\rho{=}{-}0.881$, $p{=}0.004$; entity types share model, tokenizer, and temperature, so effective degrees of freedom may be lower than 6).
121	Low degeneracy alone is not sufficient: the LoRA-rank ablation (\S\ref{sec:robustness_main}) reduces degeneracy to 7.2\% yet LP does not improve selection because $\rho(\text{LP}, \text{F1}){\approx}0.24$.
122	Few-NERD satisfies both conditions: low degeneracy (13.8\%) and strong alignment ($\rho{\approx}0.5$; per-type detail in Appendix~\ref{app:per_type_lp}).
123	All five signals achieve positive QE on Few-NERD (LP $\rho{=}0.42$, VC $0.39$), yet only LP translates QE into selection; the gap confirms that strong instance-level QE cannot rank candidates within an instance.
124	
125	\begin{figure}[t]
126	\centering
127	\includegraphics[width=\columnwidth]{figures/fig_degeneracy_lp_scatter.pdf}
128	\caption{Instance degeneracy vs.\ LP selection gain. Blue circles: cross-dataset ($n{=}3$, exploratory). Orange triangles: per-entity-type within Few-NERD ($n{=}8$, $\rho{=}{-}0.881$, $p{=}0.004$; types share model and tokenizer). The dashed line at ${\sim}$15\%\protect\footnotemark{} separates regimes where LP improves (left) vs.\ shows insufficient evidence (right).}
129	\label{fig:degeneracy_scatter}
130	\end{figure}
131	
132	\footnotetext{Boundary between Person (13.4\%, $+1.25$~pp) and Art (19.8\%, $-0.17$~pp).}
133	
134	\paragraph{LP selection scales with sample budget.}
135	Doubling $N$ from 8 to 16 on Few-NERD yields $+0.52$~pp (paired $p{=}0.003$, CI $[+0.17, +0.87]$), driven by reduced degeneracy (14.6\% $\to$ 7.0\%) expanding headroom (12.1 $\to$ 15.4~pp), while LP ranking quality remains stable ($\rho{\approx}0.62$).
136	Structural signals remain uniformly negative at $N{=}16$; the gap persists regardless of sample budget.
137	
138	%% ============================================================
139	\subsection{Robustness}
140	\label{sec:robustness_main}
141	
142	Consistency signals are robust across $T{\in}\{0.7, 1.0\}$ with sublinear $N$-scaling gains (Table~\ref{tab:robustness}); LP shows the largest temperature sensitivity ($\Delta\rho{=}{+}0.044$).
143	Signal rankings are stable across seeds (Kendall's $W{=}1.0$ at $N{=}8$, though statistical precision is limited with $m{=}3$ raters, exact $p{\approx}0.028$; Table~\ref{tab:ranking-stability}).
144	NER calibration is reasonable (ECE 0.069--0.096; Appendix~\ref{app:calibration}).
145	
146	\begin{table}[t]
147	\centering
148	\small
149	\caption{Scale ablation: Qwen3-8B vs.\ 4B NER quality estimation ($\rho$; $N{=}8$, $T{=}1.0$, seed${=}42$). 8B values identical to Table~\ref{tab:quality_estimation}; 4B uses matched evaluation protocol. RE scale ablation in Appendix~\ref{app:re_extension}.}
150	\label{tab:scale_ablation}
151	\begin{tabular}{@{}ll cc r@{}}
152	\toprule
153	& & \textbf{8B} & \textbf{4B} & $\Delta$ \\
154	\midrule
155	CoNLL & SJ & .436 & .422 & $-$.014 \\
156	      & FK & .400 & .418 & $+$.018 \\
157	SciERC & SJ & .360 & .422 & $+$.062 \\
158	       & FK & .267 & .326 & $+$.059 \\
159	\bottomrule
160	\end{tabular}
161	\end{table}
162	
163	\paragraph{Scale robustness.}
164	With Qwen3-4B (Table~\ref{tab:scale_ablation}), QE is comparable (mean $|\Delta\rho|{=}0.042$), yet selection remains below greedy despite 13.0~pp headroom. Task difficulty is a stronger predictor than model scale within the 3B--8B range (Appendix~\ref{app:llama3b}).
165	Degeneracy scales with capability: 8B shows 17.8\% vs.\ 4B's 10.4\% on SciERC (Table~\ref{tab:degeneracy}).
166	
167	\paragraph{LoRA-rank ablation.}
168	Training with LoRA rank${=}8$ (vs.\ 32) lowers degeneracy from 17.8\% to 7.2\% and increases headroom to 16.0~pp, but LP does not improve selection (0.635 vs.\ greedy 0.640).
169	This ablation conflates diversity with model capacity (rank 8 has fewer trainable parameters); within-instance $\rho(\text{LP}, \text{F1}){\approx}0.24$ remains too weak despite wider LP spread (0.057 vs.\ 0.041 nats).
170	Temperature manipulation (\S\ref{sec:discussion}) provides a cleaner test by altering diversity without changing capacity, and yields the same conclusion: both low degeneracy and adequate alignment are independently necessary.
171	
172	\paragraph{Supervised verifier baseline.}
173	Supervised verifiers (logistic regression, MLP, random forest) trained on all five signals (3-fold CV, SciERC, $N{=}16$, $+17.9$~pp headroom) all perform at or below greedy\footnote{Greedy F1 is 0.644 (3-seed mean), consistent with Table~\ref{tab:selection}.} (LR: $-0.3$~pp; MLP: $-0.6$~pp; RF: $-2.9$~pp).
174	Adding pairwise interaction features does not help (AUROC 0.632 vs.\ 0.639).
175	Within these five unsupervised signals, the bottleneck is in what they encode, not how they are combined; whether richer representations (e.g., hidden states, entity embeddings) could close the gap remains untested.
176	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "35a7fb44-bbb5-4440-8fdd-eecbd543f503",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\n\\subsection{Experimental Setup}\n\\label{sec:setup}\n\n\\paragraph{Datasets.}\nWe evaluate on four English NER benchmarks spanning a difficulty gradient, each serving a distinct role.\n\\textbf{SciERC} \\cite{luan2018scierc} (551 test instances, 6 entity types) is the primary medium-difficulty test bed where models achieve ${\\approx}$65\\% F1.\n\\textbf{Few-NERD} \\cite{ding2021fewnerd} (INTRA coarse; 37{,}648 instances, 8 entity types, ${\\approx}$75\\% F1) provides a low-degeneracy contrast where LP selection succeeds (\\S\\ref{sec:fewnerd}).\n\\textbf{CoNLL-2003} \\cite{tjongkimsang2003conll} (3{,}453 test sentences, 4 entity types, ${\\approx}$91\\% F1) serves as a ceiling-effect control where limited oracle headroom constrains selection gains.\n\\textbf{WNUT-17} \\cite{derczynski2017wnut} (1{,}287 social media instances, 52\\% zero F1) probes the signal-collapse boundary where model capability is insufficient.\n\n\\paragraph{Models and sampling.}\nBoth \\textbf{Qwen3-8B} and \\textbf{LLaMA-3.1-8B-Instruct} are fine-tuned with LoRA (rank$=$32, $\\alpha{=}64$) for 5 epochs using LLaMA Factory \\cite{zheng2024llamafactory} under identical training procedures, except Few-NERD models which use 3 epochs (early stopping at the best validation checkpoint; a 5-epoch control confirms LP selection remains positive though gains are halved; Appendix~\\ref{app:epoch_confound}).\nQwen3-8B's SciERC checkpoint has a minor train--test mismatch (empty thinking tokens); a quantitative analysis rules out this confound (Appendix~\\ref{app:thinking_token}).\nWe draw $N{=}8$ samples at $T{=}1.0$ (primary), with $N{=}16$ for scaling experiments.\\footnote{$N{=}16$ with 3 seeds verifies scaling and ranking stability ($\\sigma{\\leq}0.026$; Table~\\ref{tab:multiseed}); gains beyond $N{=}8$ are sublinear (Appendix~\\ref{app:n_scaling}).}\nInference uses vLLM with constrained decoding \\cite{willard2023guided}.\\footnote{Quality estimation uses a single primary seed (seed${=}42$); selection uses 2-seed averages for variance estimation. Three-seed experiments ($\\sigma{\\leq}0.026$; Table~\\ref{tab:multiseed}) confirm ranking stability; the reduced seed count for primary results reflects computational budget.}\n\n%% ============================================================\n\\subsection{Quality Estimation Results}\n\\label{sec:qe_results}\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{NER quality estimation ($\\rho$ and AUROC; $N{=}8$, primary seed${=}42$; 3-seed stability $\\sigma{\\leq}0.026$ in Table~\\ref{tab:multiseed}). Best in \\textbf{bold}. RE results in Appendix~\\ref{app:re_extension}. $N{=}16$ in Table~\\ref{tab:robustness}.}\n\\label{tab:quality_estimation}\n\\begin{tabular}{ll cc cc cc}\n\\toprule\n& & \\multicolumn{2}{c}{\\textbf{SciERC}} & \\multicolumn{2}{c}{\\textbf{CoNLL (Qwen)}} & \\multicolumn{2}{c}{\\textbf{CoNLL (LLaMA)}} \\\\\n\\cmidrule(lr){3-4} \\cmidrule(lr){5-6} \\cmidrule(lr){7-8}\nSignal & Family & $\\rho$ & AUC & $\\rho$ & AUC & $\\rho$ & AUC \\\\\n\\midrule\nVC & Structural & \\textbf{.379} & \\textbf{.663} & .424 & .789 & .426 & .709 \\\\\nSJ  & Structural & .360 & .650 & .436 & .801 & \\textbf{.431} & .704 \\\\\nFK & Surface & .267 & .602 & .400 & .774 & .428 & .703 \\\\\nEM  & Surface    & .295 & .614 & \\textbf{.451} & \\textbf{.816} & \\textbf{.431} & .705 \\\\\n\\midrule\nLP     & Model      & .205 & .578 & .316 & .753 & .307 & \\textbf{.761} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\nTable~\\ref{tab:quality_estimation} presents $\\rho$ and AUROC for five signals across tasks and models.\\footnote{$\\varepsilon{=}0.05$ applies only to selection (\\S\\ref{sec:selection_gap}); quality estimation is $\\varepsilon$-free. Selection F1 is stable across $\\varepsilon \\in [0, 0.2]$ (Appendix~\\ref{app:epsilon_robustness}).}\n\n\\paragraph{Signal rankings are difficulty-dependent.}\nOn SciERC (medium difficulty), structural signals lead (VC $\\rho{=}0.379$, SJ $0.360$) over LP ($0.205$); bootstrap CIs confirm the gap ($\\Delta\\rho{=}{+}0.155$; Appendix~\\ref{app:bootstrap_signal}).\nOn CoNLL (single-sample F1${\\approx}$0.91), EM leads both $\\rho$ and AUROC ($0.816$).\nAt the signal-collapse boundary (WNUT-17, macro F1${\\approx}$42\\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\\rho{=}0.724$ but conditional $\\rho{=}0.038$; Table~\\ref{tab:wnut}); LP shows the reverse (conditional $\\rho{=}0.350$; Figure~\\ref{fig:signal_heatmap}).\n\n%% ============================================================\n\\subsection{The Correlation-Selection Gap}\n\\label{sec:selection_gap}\n\nTwo mechanisms block selection: instance degeneracy collapses the candidate pool for consensus-based approaches, and weak LP-quality alignment prevents exploiting the remaining headroom.\nA methodological observation underlies both: four instance-level signals cannot rank candidates by construction; LP requires both low degeneracy and adequate alignment ($\\rho \\gtrsim 0.3$).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Best-of-$N$ NER selection (macro F1) on SciERC ($N{=}8$, $T{=}1.0$, 2-seed mean${\\pm}\\sigma$). LP is per-sample; others use consensus-proximity. Best non-oracle in \\textbf{bold}. Non-tied subset in \\S\\ref{sec:discussion}; RE in Appendix~\\ref{app:re_extension}.}\n\\label{tab:selection}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & NER F1 & $p$ \\\\\n\\midrule\nOracle & $0.778 \\pm 0.003$ & --- \\\\\nGreedy ($T{=}0$) & $0.645 \\pm 0.001$ & --- \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textit{Per-sample signal}} \\\\\nLP           & $\\mathbf{0.647} \\pm 0.005$ & .29 \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textit{Instance-level signals (consensus-proximity selection)}} \\\\\nSJ           & $0.646 \\pm 0.002$ & .67 \\\\\nFK           & $0.646 \\pm 0.001$ & .79 \\\\\nEM           & $0.637 \\pm 0.001$ & --- \\\\\nVC           & $0.623 \\pm 0.004$ & --- \\\\\n\\midrule\nRandom           & $0.610 \\pm 0.003$ & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nDespite moderate quality estimation, no signal consistently improves selection over greedy (Table~\\ref{tab:selection}).\nInstance-level signals assign identical QE scores to all candidates; MBR conversion does not improve over greedy on the primary test bed.\n\n\\paragraph{No significant improvement over greedy.}\nOn SciERC ($n{=}529$, 2-seed sign tests\\footnote{Seed variation $\\sigma{\\leq}0.026$ (Table~\\ref{tab:multiseed}); MDE${\\approx}$1.5~pp at 80\\% power for $n{=}529$, so a 1~pp effect yields only ${\\sim}$55\\% power. Few-NERD ($n{=}32{,}565$; MDE${\\approx}$0.22~pp) provides the definitive test.}), the oracle (0.778) reveals 13.3~pp of headroom, but LP achieves $+0.2$~pp ($p{=}0.29$), below the MDE (${\\approx}$1.5~pp).\nThe pattern holds across CoNLL and WNUT-17 (Table~\\ref{tab:cross_selection}); under stringent TOST anchors, some configurations show significant \\textit{degradation} (Appendix~\\ref{app:tost}).\nFew-NERD provides the definitive contrast: LP achieves $+1.36$~pp ($p{<}0.001$) at low degeneracy (\\S\\ref{sec:fewnerd}), while structural signals still degrade selection.\nInstance-level signals predict \\textit{which inputs} the model handles reliably, not \\textit{which output} is best; closing this gap likely requires trained verifiers \\cite{cobbe2021verifiers}.\\footnote{The sole positive finding (non-tied LP subset, $+2.9$~pp, $p{=}0.004$; \\S\\ref{sec:discussion}) survives Bonferroni correction over 5 comparisons.}\n\n%% ============================================================\n\\subsection{Cross-Dataset Contrast: Few-NERD}\n\\label{sec:fewnerd}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-dataset comparison of LP selection effectiveness (Qwen3-8B, $N{=}8$, $T{=}1.0$, gold-filtered). LP $\\rho$: Spearman correlation between max token-level log-probability and instance F1. LP selection gains are inversely associated with instance degeneracy.\\protect\\footnotemark\\protect\\footnotemark}\n\\label{tab:fewnerd}\n\\begin{tabular}{lcccccc}\n\\toprule\nDataset & $n$ & Greedy & Headroom & Degen\\% & LP $\\rho$ & LP $\\Delta$ \\\\\n\\midrule\nCoNLL & 2{,}756 & .908 & 4.0\\,pp & 59.1\\% & .302 & $-$1.05\\,pp \\\\\nSciERC & 529 & .644 & 13.2\\,pp & 17.8\\% & .215 & $+$0.61\\,pp \\\\\nFew-NERD & 32{,}565 & .748 & 12.4\\,pp & 13.8\\% & .421 & $\\mathbf{+1.36}$\\,pp \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\\footnotetext{SciERC values (greedy${=}0.644$, headroom${=}13.2$~pp) differ slightly from Table~\\ref{tab:selection} (greedy${=}0.645$, headroom${=}13.3$~pp) due to max-LP aggregation and single-seed evaluation; the ranking is unchanged.}\n\\footnotetext{Instance degeneracy: fraction of gold-filtered instances where all $N$ samples produce identical instance-level F1.}\n\nFew-NERD (Table~\\ref{tab:fewnerd}) confirms that LP selection effectiveness is inversely associated with degeneracy.\nUnder standard early stopping, Few-NERD degeneracy is 13.8\\% (training convergence modulates this rate, Appendix~\\ref{app:epoch_confound}), and LP achieves $+1.36$~pp (95\\% CI $[+1.18, +1.53]$, $p{<}0.001$), while all structural signals degrade selection (VC $-1.79$, SJ $-2.14$~pp).\n\n\\paragraph{Two necessary conditions for LP selection.}\nThe cross-dataset gradient is consistent with an inverse relationship (59.1\\% $\\to$ $-1.05$~pp, 17.8\\% $\\to$ $+0.61$~pp, 13.8\\% $\\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory given 5+ confounds; Figure~\\ref{fig:degeneracy_scatter}), with supporting evidence from per-entity-type analysis within Few-NERD ($n{=}8$, $\\rho{=}{-}0.881$, $p{=}0.004$; entity types share model, tokenizer, and temperature, so effective degrees of freedom may be lower than 6).\nLow degeneracy alone is not sufficient: the LoRA-rank ablation (\\S\\ref{sec:robustness_main}) reduces degeneracy to 7.2\\% yet LP does not improve selection because $\\rho(\\text{LP}, \\text{F1}){\\approx}0.24$.\nFew-NERD satisfies both conditions: low degeneracy (13.8\\%) and strong alignment ($\\rho{\\approx}0.5$; per-type detail in Appendix~\\ref{app:per_type_lp}).\nAll five signals achieve positive QE on Few-NERD (LP $\\rho{=}0.42$, VC $0.39$), yet only LP translates QE into selection; the gap confirms that strong instance-level QE cannot rank candidates within an instance.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_degeneracy_lp_scatter.pdf}\n\\caption{Instance degeneracy vs.\\ LP selection gain. Blue circles: cross-dataset ($n{=}3$, exploratory). Orange triangles: per-entity-type within Few-NERD ($n{=}8$, $\\rho{=}{-}0.881$, $p{=}0.004$; types share model and tokenizer). The dashed line at ${\\sim}$15\\%\\protect\\footnotemark{} separates regimes where LP improves (left) vs.\\ shows insufficient evidence (right).}\n\\label{fig:degeneracy_scatter}\n\\end{figure}\n\n\\footnotetext{Boundary between Person (13.4\\%, $+1.25$~pp) and Art (19.8\\%, $-0.17$~pp).}\n\n\\paragraph{LP selection scales with sample budget.}\nDoubling $N$ from 8 to 16 on Few-NERD yields $+0.52$~pp (paired $p{=}0.003$, CI $[+0.17, +0.87]$), driven by reduced degeneracy (14.6\\% $\\to$ 7.0\\%) expanding headroom (12.1 $\\to$ 15.4~pp), while LP ranking quality remains stable ($\\rho{\\approx}0.62$).\nStructural signals remain uniformly negative at $N{=}16$; the gap persists regardless of sample budget.\n\n%% ============================================================\n\\subsection{Robustness}\n\\label{sec:robustness_main}\n\nConsistency signals are robust across $T{\\in}\\{0.7, 1.0\\}$ with sublinear $N$-scaling gains (Table~\\ref{tab:robustness}); LP shows the largest temperature sensitivity ($\\Delta\\rho{=}{+}0.044$).\nSignal rankings are stable across seeds (Kendall's $W{=}1.0$ at $N{=}8$, though statistical precision is limited with $m{=}3$ raters, exact $p{\\approx}0.028$; Table~\\ref{tab:ranking-stability}).\nNER calibration is reasonable (ECE 0.069--0.096; Appendix~\\ref{app:calibration}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Scale ablation: Qwen3-8B vs.\\ 4B NER quality estimation ($\\rho$; $N{=}8$, $T{=}1.0$, seed${=}42$). 8B values identical to Table~\\ref{tab:quality_estimation}; 4B uses matched evaluation protocol. RE scale ablation in Appendix~\\ref{app:re_extension}.}\n\\label{tab:scale_ablation}\n\\begin{tabular}{@{}ll cc r@{}}\n\\toprule\n& & \\textbf{8B} & \\textbf{4B} & $\\Delta$ \\\\\n\\midrule\nCoNLL & SJ & .436 & .422 & $-$.014 \\\\\n      & FK & .400 & .418 & $+$.018 \\\\\nSciERC & SJ & .360 & .422 & $+$.062 \\\\\n       & FK & .267 & .326 & $+$.059 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Scale robustness.}\nWith Qwen3-4B (Table~\\ref{tab:scale_ablation}), QE is comparable (mean $|\\Delta\\rho|{=}0.042$), yet selection remains below greedy despite 13.0~pp headroom. Task difficulty is a stronger predictor than model scale within the 3B--8B range (Appendix~\\ref{app:llama3b}).\nDegeneracy scales with capability: 8B shows 17.8\\% vs.\\ 4B's 10.4\\% on SciERC (Table~\\ref{tab:degeneracy}).\n\n\\paragraph{LoRA-rank ablation.}\nTraining with LoRA rank${=}8$ (vs.\\ 32) lowers degeneracy from 17.8\\% to 7.2\\% and increases headroom to 16.0~pp, but LP does not improve selection (0.635 vs.\\ greedy 0.640).\nThis ablation conflates diversity with model capacity (rank 8 has fewer trainable parameters); within-instance $\\rho(\\text{LP}, \\text{F1}){\\approx}0.24$ remains too weak despite wider LP spread (0.057 vs.\\ 0.041 nats).\nTemperature manipulation (\\S\\ref{sec:discussion}) provides a cleaner test by altering diversity without changing capacity, and yields the same conclusion: both low degeneracy and adequate alignment are independently necessary.\n\n\\paragraph{Supervised verifier baseline.}\nSupervised verifiers (logistic regression, MLP, random forest) trained on all five signals (3-fold CV, SciERC, $N{=}16$, $+17.9$~pp headroom) all perform at or below greedy\\footnote{Greedy F1 is 0.644 (3-seed mean), consistent with Table~\\ref{tab:selection}.} (LR: $-0.3$~pp; MLP: $-0.6$~pp; RF: $-2.9$~pp).\nAdding pairwise interaction features does not help (AUROC 0.632 vs.\\ 0.639).\nWithin these five unsupervised signals, the bottleneck is in what they encode, not how they are combined; whether richer representations (e.g., hidden states, entity embeddings) could close the gap remains untested.\n",
      "numLines": 176,
      "startLine": 1,
      "totalLines": 176
    }
  }
}
```

</details>

---

### Tool call

_source line 15_

<details open><summary>🔧 Tool call — Read · `toolu_017JvLfH3VcQW8YnLNjXF7UB`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "8d23d8c2-46c3-4640-831a-19432fc2caf2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KioYcRTqz3d75hQTPrqcXj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1498,
      "cache_read_input_tokens": 25394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1498
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

_source line 16 · 2026-05-18T05:45:38.073Z_

<details><summary>↩ Tool result · `toolu_017JvLfH3VcQW8YnLNjXF7UB`</summary>

```text
1	\section{Discussion}\label{sec:discussion}
2	
3	\paragraph{Implications for practitioners.}
4	All signals achieve positive quality estimation across non-collapsed datasets (LP $\rho{=}0.42$ on Few-NERD, VC $\rho{=}0.38$ on SciERC, EM AUROC${=}0.82$ on CoNLL), with rankings stable across model families and a 4B ablation (Table~\ref{tab:scale_ablation}).
5	For selection, LP achieves significant gains only when both conditions are met ($+1.36$~pp on Few-NERD, $p{<}0.001$; Table~\ref{tab:fewnerd}); structural signals uniformly degrade selection.
6	RE signal rankings are in Appendix~\ref{app:re_extension}.
7	
8	\paragraph{Why the gap exists.}
9	Two mechanisms block selection: \textit{instance degeneracy} (consensus-proximity) and \textit{weak LP-quality alignment} (per-sample).
10	Within non-degenerate instances, MBR utility \cite{eikema2022sampling} correlates positively with F1 (SJ median $\rho{=}0.524$) and closes 23--41\% of the oracle gap, but 17.8\% (SciERC) to 59.1\% (CoNLL) of instances produce identical F1 across all samples, eliminating headroom entirely (Table~\ref{tab:degeneracy}).
11	Degeneracy is determined by the interplay of task structure, model architecture, and training convergence (Appendix~\ref{app:epoch_confound}); cross-model evidence (LLaMA 86.4\% vs.\ Qwen 59.1\% on CoNLL; Table~\ref{tab:cross_selection}) reinforces the pattern.
12	LP is severely compressed (median range 0.041 nats; Table~\ref{tab:logprob_ties}), with pooled within-instance $\rho(\text{LP}, \text{F1}){=}0.248$.
13	
14	\paragraph{Non-tied subset and $N$-scaling.}
15	Where compression is mitigated (LP range ${\geq}0.05$, $n{=}210$), within-instance $\rho$ rises to 0.39 and LP selection yields $+2.9$~pp ($p{=}0.004$, survives Bonferroni; Table~\ref{tab:nontied_main}).
16	LP scales with $N$ in the low-degeneracy regime ($+0.52$~pp from $N{=}8$ to 16 on Few-NERD, $p{=}0.003$; \S\ref{sec:fewnerd}); on SciERC, even $N{=}32$ captures less than 5\% of headroom (Table~\ref{tab:n_scaling_selection}).
17	An oracle tiebreaker within VC-equivalent groups recovers $+7.9$~pp, confirming per-sample signal exists but current signals cannot extract it (full analyses in Appendices~\ref{app:n_scaling}, \ref{app:verbalized_confidence}, \ref{app:vc_quartile}).
18	
19	\paragraph{LP compression mechanisms.}
20	Four non-mutually-exclusive mechanisms contribute: token-level averaging, schema-dominated tokens, vocabulary restriction under constrained decoding, and format-token dilution.
21	Free-form decoding rules out constraint-imposed mechanisms for NER (std ratio 0.97; Appendix~\ref{app:freeform_ablation}) but restores LP selection for RE ($+2.35$~pp, $p{=}0.025$; Appendix~\ref{app:re_extension}).
22	Entity-token LP exhibits $4{\times}$ higher variance yet performs worse ($-2.0$~pp SciERC, $-3.3$~pp CoNLL): fine-tuned models assign near-deterministic probabilities at the representation level, and compression cannot be broken by disaggregating to entity tokens.
23	LP failures show cross-seed stability (Jaccard${=}0.42$; Appendix~\ref{app:lp_failure_stability}), consistent with a systematic failure mode.
24	
25	\paragraph{Regime boundaries.}
26	At the low-resource boundary (WNUT-17), QE signals collapse (VC conditional $\rho{=}0.038$; Table~\ref{tab:wnut}); at the ceiling boundary (CoNLL, degeneracy 59--86\%), LP degrades selection ($-1.05$~pp).
27	In the moderate regime, two conditions jointly determine effectiveness.
28	Temperature manipulation provides the primary evidence ($T{=}1.2$: degeneracy 12.5\%, $\rho{=}0.225$; Table~\ref{tab:t_degeneracy}): it alters output diversity without changing model capacity, isolating the degeneracy lever from alignment.
29	Even at degeneracy approaching Few-NERD levels (12.5\% vs.\ 13.8\%), LP does not improve selection because alignment remains weak ($\rho{=}0.225$ vs.\ Few-NERD ${\sim}$0.5).
30	LoRA rank${=}8$ (degeneracy 7.2\%, $\rho{=}0.24$) corroborates the pattern, though this ablation conflates diversity with capacity (secondary evidence).
31	The cross-dataset gradient (59\% $\to$ $-1.05$~pp, 18\% $\to$ $+0.61$~pp, 14\% $\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory) is consistent with an inverse relationship; per-entity-type analysis within Few-NERD ($\rho{=}{-}0.881$, $p{=}0.004$, $n{=}8$; entity types share model and tokenizer, effective $\mathit{df}$ may be lower; Appendix~\ref{app:per_type_lp}) provides supporting evidence.
32	
33	\paragraph{Practical guidelines.}
34	Practitioners should first estimate instance degeneracy and LP-quality alignment on a labeled development set.
35	The decision rule is: if degeneracy ${<}$15\% and within-instance $\rho(\text{LP}, \text{F1}) \gtrsim 0.3$, use LP selection (Few-NERD: $+1.36$~pp, $p{<}0.001$; gains scale with $N$); otherwise, prefer greedy decoding ($T{=}0$), using structural signals for quality estimation only ($\rho{=}0.43$--$0.47$ even in the high-degeneracy regime; Table~\ref{tab:degeneracy}).
36	Temperature provides a controllable lever for degeneracy (40.3\% at $T{=}0.5$ to 12.5\% at $T{=}1.2$; Table~\ref{tab:t_degeneracy}) but cannot address alignment; training convergence offers a second lever: on Few-NERD, degeneracy rises from 11\% to 31\% between 3 and 5 epochs, halving LP gains (Table~\ref{tab:epoch_confound}); a SciERC 3-point curve (3, 5, 10 epochs) shows both conditions degrading in tandem, with degeneracy rising from 6.4\% to 47.8\% while within-instance alignment collapses ($\rho$: 0.317 $\to$ 0.282 $\to$ 0.120) and LP selection remains below detectable thresholds at all three checkpoints, confirming that degeneracy is convergence-driven rather than a fixed dataset property (Table~\ref{tab:epoch_scierc}); even at 3 epochs (degeneracy 6.4\%), SciERC alignment remains insufficient ($\rho{=}0.317$ vs.\ Few-NERD ${\sim}$0.5), reinforcing that low degeneracy alone does not guarantee selection gains.
37	Standard calibration methods preserve within-instance argmax and cannot change selection; even multi-feature variants yield no improvement ($p{=}0.31$--$0.83$; Appendix~\ref{app:calibration_baseline}), confirming the bottleneck is alignment rather than miscalibration.
38	
39	\paragraph{Methodological implications.}
40	The decoupling of $\rho$, AUROC, and selection F1 means single-metric evaluation risks selecting the wrong signal; even supervised combination of these five unsupervised signals does not close the oracle gap (\S\ref{sec:robustness_main}).
41	Effective selection requires content-aware verifiers \cite{cobbe2021verifiers, venktesh2025trust}; $N{=}8$ captures most QE benefit (Appendix~\ref{app:n_scaling}).
42	Structural signals are robust to domain shift when the training schema subsumes the target (Appendix~\ref{app:ood}).
43	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "3858774f-2222-4746-9988-af0f0c36e0e7",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex",
      "content": "\\section{Discussion}\\label{sec:discussion}\n\n\\paragraph{Implications for practitioners.}\nAll signals achieve positive quality estimation across non-collapsed datasets (LP $\\rho{=}0.42$ on Few-NERD, VC $\\rho{=}0.38$ on SciERC, EM AUROC${=}0.82$ on CoNLL), with rankings stable across model families and a 4B ablation (Table~\\ref{tab:scale_ablation}).\nFor selection, LP achieves significant gains only when both conditions are met ($+1.36$~pp on Few-NERD, $p{<}0.001$; Table~\\ref{tab:fewnerd}); structural signals uniformly degrade selection.\nRE signal rankings are in Appendix~\\ref{app:re_extension}.\n\n\\paragraph{Why the gap exists.}\nTwo mechanisms block selection: \\textit{instance degeneracy} (consensus-proximity) and \\textit{weak LP-quality alignment} (per-sample).\nWithin non-degenerate instances, MBR utility \\cite{eikema2022sampling} correlates positively with F1 (SJ median $\\rho{=}0.524$) and closes 23--41\\% of the oracle gap, but 17.8\\% (SciERC) to 59.1\\% (CoNLL) of instances produce identical F1 across all samples, eliminating headroom entirely (Table~\\ref{tab:degeneracy}).\nDegeneracy is determined by the interplay of task structure, model architecture, and training convergence (Appendix~\\ref{app:epoch_confound}); cross-model evidence (LLaMA 86.4\\% vs.\\ Qwen 59.1\\% on CoNLL; Table~\\ref{tab:cross_selection}) reinforces the pattern.\nLP is severely compressed (median range 0.041 nats; Table~\\ref{tab:logprob_ties}), with pooled within-instance $\\rho(\\text{LP}, \\text{F1}){=}0.248$.\n\n\\paragraph{Non-tied subset and $N$-scaling.}\nWhere compression is mitigated (LP range ${\\geq}0.05$, $n{=}210$), within-instance $\\rho$ rises to 0.39 and LP selection yields $+2.9$~pp ($p{=}0.004$, survives Bonferroni; Table~\\ref{tab:nontied_main}).\nLP scales with $N$ in the low-degeneracy regime ($+0.52$~pp from $N{=}8$ to 16 on Few-NERD, $p{=}0.003$; \\S\\ref{sec:fewnerd}); on SciERC, even $N{=}32$ captures less than 5\\% of headroom (Table~\\ref{tab:n_scaling_selection}).\nAn oracle tiebreaker within VC-equivalent groups recovers $+7.9$~pp, confirming per-sample signal exists but current signals cannot extract it (full analyses in Appendices~\\ref{app:n_scaling}, \\ref{app:verbalized_confidence}, \\ref{app:vc_quartile}).\n\n\\paragraph{LP compression mechanisms.}\nFour non-mutually-exclusive mechanisms contribute: token-level averaging, schema-dominated tokens, vocabulary restriction under constrained decoding, and format-token dilution.\nFree-form decoding rules out constraint-imposed mechanisms for NER (std ratio 0.97; Appendix~\\ref{app:freeform_ablation}) but restores LP selection for RE ($+2.35$~pp, $p{=}0.025$; Appendix~\\ref{app:re_extension}).\nEntity-token LP exhibits $4{\\times}$ higher variance yet performs worse ($-2.0$~pp SciERC, $-3.3$~pp CoNLL): fine-tuned models assign near-deterministic probabilities at the representation level, and compression cannot be broken by disaggregating to entity tokens.\nLP failures show cross-seed stability (Jaccard${=}0.42$; Appendix~\\ref{app:lp_failure_stability}), consistent with a systematic failure mode.\n\n\\paragraph{Regime boundaries.}\nAt the low-resource boundary (WNUT-17), QE signals collapse (VC conditional $\\rho{=}0.038$; Table~\\ref{tab:wnut}); at the ceiling boundary (CoNLL, degeneracy 59--86\\%), LP degrades selection ($-1.05$~pp).\nIn the moderate regime, two conditions jointly determine effectiveness.\nTemperature manipulation provides the primary evidence ($T{=}1.2$: degeneracy 12.5\\%, $\\rho{=}0.225$; Table~\\ref{tab:t_degeneracy}): it alters output diversity without changing model capacity, isolating the degeneracy lever from alignment.\nEven at degeneracy approaching Few-NERD levels (12.5\\% vs.\\ 13.8\\%), LP does not improve selection because alignment remains weak ($\\rho{=}0.225$ vs.\\ Few-NERD ${\\sim}$0.5).\nLoRA rank${=}8$ (degeneracy 7.2\\%, $\\rho{=}0.24$) corroborates the pattern, though this ablation conflates diversity with capacity (secondary evidence).\nThe cross-dataset gradient (59\\% $\\to$ $-1.05$~pp, 18\\% $\\to$ $+0.61$~pp, 14\\% $\\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory) is consistent with an inverse relationship; per-entity-type analysis within Few-NERD ($\\rho{=}{-}0.881$, $p{=}0.004$, $n{=}8$; entity types share model and tokenizer, effective $\\mathit{df}$ may be lower; Appendix~\\ref{app:per_type_lp}) provides supporting evidence.\n\n\\paragraph{Practical guidelines.}\nPractitioners should first estimate instance degeneracy and LP-quality alignment on a labeled development set.\nThe decision rule is: if degeneracy ${<}$15\\% and within-instance $\\rho(\\text{LP}, \\text{F1}) \\gtrsim 0.3$, use LP selection (Few-NERD: $+1.36$~pp, $p{<}0.001$; gains scale with $N$); otherwise, prefer greedy decoding ($T{=}0$), using structural signals for quality estimation only ($\\rho{=}0.43$--$0.47$ even in the high-degeneracy regime; Table~\\ref{tab:degeneracy}).\nTemperature provides a controllable lever for degeneracy (40.3\\% at $T{=}0.5$ to 12.5\\% at $T{=}1.2$; Table~\\ref{tab:t_degeneracy}) but cannot address alignment; training convergence offers a second lever: on Few-NERD, degeneracy rises from 11\\% to 31\\% between 3 and 5 epochs, halving LP gains (Table~\\ref{tab:epoch_confound}); a SciERC 3-point curve (3, 5, 10 epochs) shows both conditions degrading in tandem, with degeneracy rising from 6.4\\% to 47.8\\% while within-instance alignment collapses ($\\rho$: 0.317 $\\to$ 0.282 $\\to$ 0.120) and LP selection remains below detectable thresholds at all three checkpoints, confirming that degeneracy is convergence-driven rather than a fixed dataset property (Table~\\ref{tab:epoch_scierc}); even at 3 epochs (degeneracy 6.4\\%), SciERC alignment remains insufficient ($\\rho{=}0.317$ vs.\\ Few-NERD ${\\sim}$0.5), reinforcing that low degeneracy alone does not guarantee selection gains.\nStandard calibration methods preserve within-instance argmax and cannot change selection; even multi-feature variants yield no improvement ($p{=}0.31$--$0.83$; Appendix~\\ref{app:calibration_baseline}), confirming the bottleneck is alignment rather than miscalibration.\n\n\\paragraph{Methodological implications.}\nThe decoupling of $\\rho$, AUROC, and selection F1 means single-metric evaluation risks selecting the wrong signal; even supervised combination of these five unsupervised signals does not close the oracle gap (\\S\\ref{sec:robustness_main}).\nEffective selection requires content-aware verifiers \\cite{cobbe2021verifiers, venktesh2025trust}; $N{=}8$ captures most QE benefit (Appendix~\\ref{app:n_scaling}).\nStructural signals are robust to domain shift when the training schema subsumes the target (Appendix~\\ref{app:ood}).\n",
      "numLines": 43,
      "startLine": 1,
      "totalLines": 43
    }
  }
}
```

</details>

---

### Tool call

_source line 17_

<details open><summary>🔧 Tool call — Read · `toolu_01A1PBcLsB9BUMeywXhhpSZ7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "fb7c23ad-2dbd-4728-8d7a-9fe633edcb4e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KioYcRTqz3d75hQTPrqcXj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1498,
      "cache_read_input_tokens": 25394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1498
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

_source line 18 · 2026-05-18T05:45:38.544Z_

<details><summary>↩ Tool result · `toolu_01A1PBcLsB9BUMeywXhhpSZ7`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	We evaluate five confidence signals for quality estimation and sample selection in LLM-based NER across four benchmarks spanning a difficulty gradient.
4	All signals achieve reliable quality estimation ($\rho$ up to 0.42, AUROC up to 0.82), supporting selective prediction.
5	For selection, LP achieves $+1.36$~pp on Few-NERD ($p{<}0.001$) when two conditions are jointly met: low instance degeneracy (${<}$15\%) and adequate LP-quality alignment ($\rho \gtrsim 0.3$); gains scale with sample budget ($+0.52$~pp, $N{=}8{\to}16$, $p{=}0.003$).
6	When either condition is violated, LP gains fall below detectable thresholds despite 12\textendash 14~pp oracle headroom: on SciERC (17.8\% degeneracy, $\rho{\approx}0.24$), LP yields $+0.61$~pp (below the ${\approx}$1.5~pp MDE at 80\% power); on CoNLL (59.1\% degeneracy), LP degrades selection ($-1.05$~pp).
7	Two mechanisms explain this gap: instance degeneracy (14\textendash 59\% of instances yield identical F1 scores) eliminates headroom, and weak LP-quality alignment prevents exploiting the remainder.
8	Structural signals do not improve selection regardless of degeneracy, and supervised combination of these five unsupervised signals does not close the oracle gap; whether richer representations (e.g., hidden states, entity embeddings) could change this conclusion remains open.
9	Whether these patterns persist at 70B+ scales remains open.
10	Closing the gap for structural signals likely requires content-aware verifiers \cite{cobbe2021verifiers}; LP provides a practical baseline when both conditions are met, with degeneracy controllable via temperature and training convergence.
11	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "3aff1770-d0a5-45d2-b066-68b8d68fe27d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/conclusion.tex",
      "content": "\\section{Conclusion}\\label{sec:conclusion}\n\nWe evaluate five confidence signals for quality estimation and sample selection in LLM-based NER across four benchmarks spanning a difficulty gradient.\nAll signals achieve reliable quality estimation ($\\rho$ up to 0.42, AUROC up to 0.82), supporting selective prediction.\nFor selection, LP achieves $+1.36$~pp on Few-NERD ($p{<}0.001$) when two conditions are jointly met: low instance degeneracy (${<}$15\\%) and adequate LP-quality alignment ($\\rho \\gtrsim 0.3$); gains scale with sample budget ($+0.52$~pp, $N{=}8{\\to}16$, $p{=}0.003$).\nWhen either condition is violated, LP gains fall below detectable thresholds despite 12\\textendash 14~pp oracle headroom: on SciERC (17.8\\% degeneracy, $\\rho{\\approx}0.24$), LP yields $+0.61$~pp (below the ${\\approx}$1.5~pp MDE at 80\\% power); on CoNLL (59.1\\% degeneracy), LP degrades selection ($-1.05$~pp).\nTwo mechanisms explain this gap: instance degeneracy (14\\textendash 59\\% of instances yield identical F1 scores) eliminates headroom, and weak LP-quality alignment prevents exploiting the remainder.\nStructural signals do not improve selection regardless of degeneracy, and supervised combination of these five unsupervised signals does not close the oracle gap; whether richer representations (e.g., hidden states, entity embeddings) could change this conclusion remains open.\nWhether these patterns persist at 70B+ scales remains open.\nClosing the gap for structural signals likely requires content-aware verifiers \\cite{cobbe2021verifiers}; LP provides a practical baseline when both conditions are met, with degeneracy controllable via temperature and training convergence.\n",
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

_source line 19_

<details open><summary>🔧 Tool call — Read · `toolu_01BmiwtcmRwYt2FmmNR5r2G7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "a145e148-d0c6-495d-a215-7c50b2ec407c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KioYcRTqz3d75hQTPrqcXj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1498,
      "cache_read_input_tokens": 25394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1498
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

_source line 20 · 2026-05-18T05:45:39.020Z_

<details><summary>↩ Tool result · `toolu_01BmiwtcmRwYt2FmmNR5r2G7`</summary>

```text
1	Our evaluation covers four NER datasets; an exploratory RE extension on SciERC is reported in Appendix~\ref{app:re_extension} but generalization to other RE benchmarks remains unvalidated.
2	We cover 4B\textendash 8B scale; whether the gap holds for 70B+ models or closed-source APIs is untested. Larger models may produce more diverse samples (potentially reducing degeneracy), but their LP-quality alignment behavior is unknown, and the two conditions may shift in opposite directions.
3	We do not train a verifier, leaving unknown how much oracle headroom a supervised approach could recover.
4	
5	We evaluate at $N{=}8$ (primary) and $N{=}16$; behavior at larger sample sizes is unknown (Appendix~\ref{app:n_scaling}).
6	The free-form ablation covers SciERC NER and CoNLL NER with one model; RE free-form results are in Appendix~\ref{app:re_extension}.
7	Qwen3-8B's SciERC checkpoint used empty \texttt{&lt;think>&lt;/think>} blocks; a three-part analysis rules out this confound (Appendix~\ref{app:thinking_token}).
8	LP compression worsens on easy datasets at lower temperature (CoNLL tied fractions reach 95.8\% at $T{=}0.7$); whether reduced temperature translates to selection gains remains untested.
9	We tested verbalized confidence \cite{tian2023calibration} as a second per-sample signal; it exhibits severe overconfidence (mean 8.58/10 on SciERC, 9.24/10 on CoNLL) and yields the weakest QE and selection among all signals (Appendix~\ref{app:verbalized_confidence}).
10	Ad-hoc LP${\times}$VC combinations yield at most $+0.2$~pp over greedy (not significant; \S\ref{sec:discussion}); whether \textit{learned} combinations could close the gap remains open.
11	The $\varepsilon{=}0.05$ threshold used for tied/non-tied LP stratification is a post-hoc exploratory choice; while selection F1 is stable across $\varepsilon \in [0, 0.2]$ (Appendix~\ref{app:epsilon_robustness}), the specific subset gains should be interpreted as characterizing the compression phenomenon rather than as a tuned selection strategy.
12	We tested one remedy for LP compression (entity-token-only LP, excluding format/schema tokens) which fails to improve selection despite increasing within-instance variance on SciERC ($4{\times}$); LP${\times}$VC combinations also fail to recover selection (\S\ref{sec:discussion}). Our supervised verifier baseline uses only the five unsupervised signals studied; richer representations (hidden states, entity embeddings) remain unexplored and could potentially close the gap. Calibration-based approaches are also untested.
13	Our selection experiments use 2 training seeds (stability $\sigma{\leq}0.026$); while within-seed statistical power is high ($n{=}32{,}565$ for Few-NERD), training seed stochasticity is not exhaustively quantified.
14	Few-NERD models are trained for 3 epochs (vs.\ 5 for other datasets) due to earlier convergence; epoch confound analyses on both Few-NERD (2-point) and SciERC (3-point, including 10-epoch overfitting) are provided in Appendix~\ref{app:epoch_confound}.
15	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "856c3865-3f36-4977-ad56-37e7bd7ca0ae",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex",
      "content": "Our evaluation covers four NER datasets; an exploratory RE extension on SciERC is reported in Appendix~\\ref{app:re_extension} but generalization to other RE benchmarks remains unvalidated.\nWe cover 4B\\textendash 8B scale; whether the gap holds for 70B+ models or closed-source APIs is untested. Larger models may produce more diverse samples (potentially reducing degeneracy), but their LP-quality alignment behavior is unknown, and the two conditions may shift in opposite directions.\nWe do not train a verifier, leaving unknown how much oracle headroom a supervised approach could recover.\n\nWe evaluate at $N{=}8$ (primary) and $N{=}16$; behavior at larger sample sizes is unknown (Appendix~\\ref{app:n_scaling}).\nThe free-form ablation covers SciERC NER and CoNLL NER with one model; RE free-form results are in Appendix~\\ref{app:re_extension}.\nQwen3-8B's SciERC checkpoint used empty \\texttt{&lt;think>&lt;/think>} blocks; a three-part analysis rules out this confound (Appendix~\\ref{app:thinking_token}).\nLP compression worsens on easy datasets at lower temperature (CoNLL tied fractions reach 95.8\\% at $T{=}0.7$); whether reduced temperature translates to selection gains remains untested.\nWe tested verbalized confidence \\cite{tian2023calibration} as a second per-sample signal; it exhibits severe overconfidence (mean 8.58/10 on SciERC, 9.24/10 on CoNLL) and yields the weakest QE and selection among all signals (Appendix~\\ref{app:verbalized_confidence}).\nAd-hoc LP${\\times}$VC combinations yield at most $+0.2$~pp over greedy (not significant; \\S\\ref{sec:discussion}); whether \\textit{learned} combinations could close the gap remains open.\nThe $\\varepsilon{=}0.05$ threshold used for tied/non-tied LP stratification is a post-hoc exploratory choice; while selection F1 is stable across $\\varepsilon \\in [0, 0.2]$ (Appendix~\\ref{app:epsilon_robustness}), the specific subset gains should be interpreted as characterizing the compression phenomenon rather than as a tuned selection strategy.\nWe tested one remedy for LP compression (entity-token-only LP, excluding format/schema tokens) which fails to improve selection despite increasing within-instance variance on SciERC ($4{\\times}$); LP${\\times}$VC combinations also fail to recover selection (\\S\\ref{sec:discussion}). Our supervised verifier baseline uses only the five unsupervised signals studied; richer representations (hidden states, entity embeddings) remain unexplored and could potentially close the gap. Calibration-based approaches are also untested.\nOur selection experiments use 2 training seeds (stability $\\sigma{\\leq}0.026$); while within-seed statistical power is high ($n{=}32{,}565$ for Few-NERD), training seed stochasticity is not exhaustively quantified.\nFew-NERD models are trained for 3 epochs (vs.\\ 5 for other datasets) due to earlier convergence; epoch confound analyses on both Few-NERD (2-point) and SciERC (3-point, including 10-epoch overfitting) are provided in Appendix~\\ref{app:epoch_confound}.\n",
      "numLines": 15,
      "startLine": 1,
      "totalLines": 15
    }
  }
}
```

</details>

---

### Tool call

_source line 21_

<details open><summary>🔧 Tool call — Read · `toolu_01SgPghZRgXUfzh55vAdHKcg`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "39fcc21a-ad65-4b70-b8fa-ad860f7b118f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KioYcRTqz3d75hQTPrqcXj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1498,
      "cache_read_input_tokens": 25394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1498
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

_source line 22 · 2026-05-18T05:45:39.484Z_

<details><summary>↩ Tool result · `toolu_01SgPghZRgXUfzh55vAdHKcg`</summary>

```text
1	\section{Method}\label{sec:method}
2	
3	\subsection{Problem Formulation}\label{sec:formulation}
4	
5	Given model $\mathcal{M}$ and input $x$, we sample $N$ outputs $\{y_1, \ldots, y_N\}$ at temperature $T > 0$ via constrained decoding \cite{willard2023guided}, where each $y_i$ is an entity set.
6	A \textbf{per-sample signal} $c_{\text{ps}}: (x, y_i) \to \mathbb{R}$ scores each output independently; an \textbf{instance-level signal} $c_{\text{il}}: (x, \{y_i\}_{i=1}^N) \to \mathbb{R}$ produces a single score per input (notation in Appendix~\ref{app:notation}).
7	This distinction is consequential for selection: in our study, 4 of 5 signals are instance-level aggregates that assign identical QE scores to all $N$ candidates. Consensus-proximity (MBR) converts these to per-sample rankings (\S\ref{sec:selection_gap}), but these rankings do not improve selection; only natively per-sample signals can, in principle, exploit oracle headroom.
8	
9	\subsection{Confidence Signals}\label{sec:signals}
10	
11	Four are \textit{consistency signals}: \textit{structural} (Soft Jaccard [SJ], entity voting confidence [VC]) and \textit{surface} (exact match [EM], Fleiss' $\kappa$ [FK]); log-probability [LP] is the sole \textit{model-internal}, per-sample signal.
12	
13	\paragraph{Log-probability (model-internal, per-sample).}
14	For sample $y_i$ with tokens $t_1, \ldots, t_{|y_i|}$:
15	\begin{equation}\label{eq:logprob}
16	c_{\text{lp}}(y_i) = \frac{1}{|y_i|} \sum_{j=1}^{|y_i|} \log p_{\mathcal{M}}(t_j \mid t_{&lt;j}, x)
17	\end{equation}
18	
19	\paragraph{Exact match voting (surface, instance-level).}
20	The proportion of samples producing the most common output:
21	\begin{equation}\label{eq:em}
22	c_{\text{em}}(x) = \frac{1}{N} \max_{y} \big|\{i : y_i = y\}\big|
23	\end{equation}
24	
25	\paragraph{Fleiss' $\kappa$ (surface, instance-level).}
26	We adapt \citet{fleiss1971agreement} to entity sets: items are unique (text, type) tuples across all $N$ samples; each sample assigns binary present/absent labels, yielding a $|E_\cup| \times 2$ rating matrix:
27	\begin{equation}\label{eq:fk}
28	\kappa = \frac{\bar{P} - \bar{P}_e}{1 - \bar{P}_e}
29	\end{equation}
30	where $\bar{P}$ is mean observed and $\bar{P}_e$ expected agreement.
31	Temperature-based sampling introduces mild negative dependence ($-$0.4\% to $-$4.0\%; Appendix~\ref{app:fk_independence}), which does not inflate FK.
32	Unlike structural signals, FK relies on exact string matching.
33	
34	\paragraph{Soft Jaccard (structural, instance-level).}
35	For samples $y_i, y_j$, we group extractions by type, compute max-weight bipartite matching (Hungarian algorithm, token-level IoU), and define:
36	\begin{equation}\label{eq:sj}
37	\text{SJ}(y_i, y_j) = \frac{\sum_{m \in M} \text{sim}(a_m, b_m)}{\sum_{g} \max(|g_i|, |g_j|)}
38	\end{equation}
39	where $M$ is the matched set, $\text{sim}(a_m, b_m)$ is the token-level IoU, and $\max(|g_i|, |g_j|)$ penalizes length asymmetry.\footnote{The two normalizer variants produce nearly identical rankings ($|\Delta\rho|{\leq}0.009$; Table~\ref{tab:sj_normalizer}).}
40	The instance-level QE signal averages over all pairs: $c_{\text{sj}}(x) = \binom{N}{2}^{-1} \sum_{i&lt;j} \text{SJ}(y_i, y_j)$.
41	For selection, consensus-proximity converts this to per-sample utility $u_{\text{sj}}(y_i) = (N{-}1)^{-1} \sum_{j \neq i} \text{SJ}(y_i, y_j)$, equivalent to MBR decoding \cite{eikema2022sampling}. The same construction applies to FK, EM, and VC.
42	
43	\paragraph{Entity voting confidence (structural, instance-level).}
44	For each entity $e$ in the union $E_\cup$ of all samples, we compute frequency $\text{freq}(e) = |\{i : e \in y_i\}| / N$.
45	The instance-level confidence is the mean frequency:
46	\begin{equation}\label{eq:voting}
47	c_{\text{vote}}(x) = \frac{1}{|E_\cup|} \sum_{e \in E_\cup} \text{freq}(e)
48	\end{equation}
49	When $E_\cup = \emptyset$, $c_{\mathrm{vc}}(x) = 0$.\footnote{For voted-output \textit{selection}, we include only entities with frequency ${>}N/2$ (standard majority voting).}
50	
51	\subsection{Evaluation Framework}\label{sec:evaluation}
52	
53	\paragraph{Quality estimation.}
54	Spearman $\rho$ between the signal and instance-level F1, and AUROC classifying instances as above/below median F1.
55	Both quality estimation and selection exclude instances with no gold annotations: $n{=}529$ on SciERC (from 551), $n{=}2{,}756$ on CoNLL (from 3{,}453).\footnote{On CoNLL, full-set ($n{=}3{,}453$) Spearman $\rho$ values are higher than gold-filtered ($n{=}2{,}756$) by $+0.03$--$0.05$ due to the zero/non-zero boundary inflating correlations, paralleling the effect documented for WNUT-17 in Appendix~\ref{app:additional}.}
56	
57	\paragraph{Sample selection.}
58	Best-of-$N$ F1: per-sample signals (LP) directly rank candidates; instance-level signals rank via consensus-proximity (MBR utility; see SJ definition above).
59	Baselines: \textit{oracle} (highest-F1 sample) and \textit{greedy} ($T{=}0$ argmax decoding).
60	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "7ff1ca84-25ca-4673-a12a-0a343b4bc21d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex",
      "content": "\\section{Method}\\label{sec:method}\n\n\\subsection{Problem Formulation}\\label{sec:formulation}\n\nGiven model $\\mathcal{M}$ and input $x$, we sample $N$ outputs $\\{y_1, \\ldots, y_N\\}$ at temperature $T > 0$ via constrained decoding \\cite{willard2023guided}, where each $y_i$ is an entity set.\nA \\textbf{per-sample signal} $c_{\\text{ps}}: (x, y_i) \\to \\mathbb{R}$ scores each output independently; an \\textbf{instance-level signal} $c_{\\text{il}}: (x, \\{y_i\\}_{i=1}^N) \\to \\mathbb{R}$ produces a single score per input (notation in Appendix~\\ref{app:notation}).\nThis distinction is consequential for selection: in our study, 4 of 5 signals are instance-level aggregates that assign identical QE scores to all $N$ candidates. Consensus-proximity (MBR) converts these to per-sample rankings (\\S\\ref{sec:selection_gap}), but these rankings do not improve selection; only natively per-sample signals can, in principle, exploit oracle headroom.\n\n\\subsection{Confidence Signals}\\label{sec:signals}\n\nFour are \\textit{consistency signals}: \\textit{structural} (Soft Jaccard [SJ], entity voting confidence [VC]) and \\textit{surface} (exact match [EM], Fleiss' $\\kappa$ [FK]); log-probability [LP] is the sole \\textit{model-internal}, per-sample signal.\n\n\\paragraph{Log-probability (model-internal, per-sample).}\nFor sample $y_i$ with tokens $t_1, \\ldots, t_{|y_i|}$:\n\\begin{equation}\\label{eq:logprob}\nc_{\\text{lp}}(y_i) = \\frac{1}{|y_i|} \\sum_{j=1}^{|y_i|} \\log p_{\\mathcal{M}}(t_j \\mid t_{&lt;j}, x)\n\\end{equation}\n\n\\paragraph{Exact match voting (surface, instance-level).}\nThe proportion of samples producing the most common output:\n\\begin{equation}\\label{eq:em}\nc_{\\text{em}}(x) = \\frac{1}{N} \\max_{y} \\big|\\{i : y_i = y\\}\\big|\n\\end{equation}\n\n\\paragraph{Fleiss' $\\kappa$ (surface, instance-level).}\nWe adapt \\citet{fleiss1971agreement} to entity sets: items are unique (text, type) tuples across all $N$ samples; each sample assigns binary present/absent labels, yielding a $|E_\\cup| \\times 2$ rating matrix:\n\\begin{equation}\\label{eq:fk}\n\\kappa = \\frac{\\bar{P} - \\bar{P}_e}{1 - \\bar{P}_e}\n\\end{equation}\nwhere $\\bar{P}$ is mean observed and $\\bar{P}_e$ expected agreement.\nTemperature-based sampling introduces mild negative dependence ($-$0.4\\% to $-$4.0\\%; Appendix~\\ref{app:fk_independence}), which does not inflate FK.\nUnlike structural signals, FK relies on exact string matching.\n\n\\paragraph{Soft Jaccard (structural, instance-level).}\nFor samples $y_i, y_j$, we group extractions by type, compute max-weight bipartite matching (Hungarian algorithm, token-level IoU), and define:\n\\begin{equation}\\label{eq:sj}\n\\text{SJ}(y_i, y_j) = \\frac{\\sum_{m \\in M} \\text{sim}(a_m, b_m)}{\\sum_{g} \\max(|g_i|, |g_j|)}\n\\end{equation}\nwhere $M$ is the matched set, $\\text{sim}(a_m, b_m)$ is the token-level IoU, and $\\max(|g_i|, |g_j|)$ penalizes length asymmetry.\\footnote{The two normalizer variants produce nearly identical rankings ($|\\Delta\\rho|{\\leq}0.009$; Table~\\ref{tab:sj_normalizer}).}\nThe instance-level QE signal averages over all pairs: $c_{\\text{sj}}(x) = \\binom{N}{2}^{-1} \\sum_{i&lt;j} \\text{SJ}(y_i, y_j)$.\nFor selection, consensus-proximity converts this to per-sample utility $u_{\\text{sj}}(y_i) = (N{-}1)^{-1} \\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$, equivalent to MBR decoding \\cite{eikema2022sampling}. The same construction applies to FK, EM, and VC.\n\n\\paragraph{Entity voting confidence (structural, instance-level).}\nFor each entity $e$ in the union $E_\\cup$ of all samples, we compute frequency $\\text{freq}(e) = |\\{i : e \\in y_i\\}| / N$.\nThe instance-level confidence is the mean frequency:\n\\begin{equation}\\label{eq:voting}\nc_{\\text{vote}}(x) = \\frac{1}{|E_\\cup|} \\sum_{e \\in E_\\cup} \\text{freq}(e)\n\\end{equation}\nWhen $E_\\cup = \\emptyset$, $c_{\\mathrm{vc}}(x) = 0$.\\footnote{For voted-output \\textit{selection}, we include only entities with frequency ${>}N/2$ (standard majority voting).}\n\n\\subsection{Evaluation Framework}\\label{sec:evaluation}\n\n\\paragraph{Quality estimation.}\nSpearman $\\rho$ between the signal and instance-level F1, and AUROC classifying instances as above/below median F1.\nBoth quality estimation and selection exclude instances with no gold annotations: $n{=}529$ on SciERC (from 551), $n{=}2{,}756$ on CoNLL (from 3{,}453).\\footnote{On CoNLL, full-set ($n{=}3{,}453$) Spearman $\\rho$ values are higher than gold-filtered ($n{=}2{,}756$) by $+0.03$--$0.05$ due to the zero/non-zero boundary inflating correlations, paralleling the effect documented for WNUT-17 in Appendix~\\ref{app:additional}.}\n\n\\paragraph{Sample selection.}\nBest-of-$N$ F1: per-sample signals (LP) directly rank candidates; instance-level signals rank via consensus-proximity (MBR utility; see SJ definition above).\nBaselines: \\textit{oracle} (highest-F1 sample) and \\textit{greedy} ($T{=}0$ argmax decoding).\n",
      "numLines": 60,
      "startLine": 1,
      "totalLines": 60
    }
  }
}
```

</details>

---

### Tool call

_source line 23_

<details open><summary>🔧 Tool call — Read · `toolu_012ZUE3PcAKXhhoSPWmPHGTM`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "b31ccc30-3142-4c13-aa8a-07edf0b69f47",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KioYcRTqz3d75hQTPrqcXj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1498,
      "cache_read_input_tokens": 25394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1498
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

_source line 24 · 2026-05-18T05:45:40.074Z_

<details><summary>↩ Tool result · `toolu_012ZUE3PcAKXhhoSPWmPHGTM`</summary>

```text
1	\section{Related Work}\label{sec:related}
2	
3	\paragraph{Self-consistency and test-time scaling.}
4	Self-consistency \cite{wang2023selfconsistency} improves reasoning via majority voting; extensions handle free-form text \cite{chen2024usc, thirukovalluru2024atomic, manakul2023selfcheckgpt}.
5	Test-time scaling studies \cite{snell2025scaling, brown2024monkeys} and reward-free selectors \cite{taubenfeld2025cisc, kang2025selfcertainty, kim2026reasc, wang2025rankedvoting, oh2026latentsc} all rely on answer-level agreement; \citet{feng2025optimal} and \citet{wang2025make} adapt to difficulty-aware settings; \citet{li2025llms} propose generative self-aggregation for IE but focus on fusion rather than selection.
6	We extend self-consistency to set-valued structured outputs and identify the correlation-selection gap.
7	
8	\paragraph{Consistency for structured IE.}
9	\citet{yao2026consistency} show consistency correlates with accuracy for LLM-based NER/RE; we show correlation is necessary but not sufficient, diagnosing degeneracy and compression as blocking mechanisms.
10	Our experiments use fine-tuned models, where degeneracy is most pronounced and is modulated by task structure and training convergence (Appendix~\ref{app:epoch_confound}).
11	CoCoA \cite{vashurin2025cocoa} fuses confidence with consistency for QA/summarization; our supervised verifier baseline (\S\ref{sec:robustness_main}) suggests combination strategy is not the bottleneck.
12	Earlier work on confidence for structured prediction \cite{culotta2004confidence, mejer2010confidence, fomicheva2020unsupervised} establishes the paradigm we extend to set-valued outputs.
13	Our evaluation builds on generative IE \cite{zhou2024uniner, sainz2024gollie, li2023codeie, wadhwa2023revisiting} and constrained decoding \cite{willard2023guided, park2024grammar, schall2025hidden, yun2025price}.
14	
15	\paragraph{Uncertainty estimation and MBR decoding.}
16	Surveys cover confidence estimation \cite{geng2024confidence}, uncertainty quantification \cite{xia2025survey}, and calibration \cite{hobelsberger2025systematic}; semantic uncertainty \cite{kuhn2023semantic} and P(True) \cite{kadavath2022language} provide model-internal alternatives.
17	Our selection strategies instantiate MBR decoding \cite{eikema2022sampling, deguchi2024centroid}; unlike MT where MBR yields consistent gains \cite{freitag2022high} and code generation where execution-based MBR improves selection \cite{shi2022mbr}, instance degeneracy eliminates the headroom MBR needs even when utility is well-aligned ($\rho{=}0.52$; \S\ref{sec:discussion}).
18	\citet{eikema2025structured} find MBR utilities degrade on structured outputs; our diagnosis is complementary: degeneracy, not utility misalignment, is the primary bottleneck.
19	Our QE results connect to selective prediction \cite{kuleshov2015calibrated}: signals with AUROC up to 0.82 support abstention policies independent of sample selection.
20	
21	\paragraph{Best-of-$N$ with learned verifiers.}
22	\citet{gao2023scaling} establish BoN scaling laws; our unsupervised signals face a more fundamental limitation than reward overoptimization.
23	Trained verifiers \cite{cobbe2021verifiers, lightman2024verify, fernandes2022quality} learn per-sample scoring; reward model ensembles mitigate but do not eliminate reward hacking \cite{eisenstein2023helping}. Our LoRA-rank ablation (degeneracy 7.2\%, selection still shows no improvement at $\rho{\approx}0.24$) suggests that, within the five unsupervised signals studied, increasing output diversity alone is insufficient.
24	Fine-tuning contributes to degeneracy, analogous to diversity collapse in RLHF \cite{kirk2024understanding}; constrained structured outputs limit the diversity that temperature scaling \cite{holtzman2020curious} or diverse decoding \cite{vijayakumar2018diverse} can recover.
25	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "0507b9d4-be4b-45d8-9729-da80dac03c7a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/related_work.tex",
      "content": "\\section{Related Work}\\label{sec:related}\n\n\\paragraph{Self-consistency and test-time scaling.}\nSelf-consistency \\cite{wang2023selfconsistency} improves reasoning via majority voting; extensions handle free-form text \\cite{chen2024usc, thirukovalluru2024atomic, manakul2023selfcheckgpt}.\nTest-time scaling studies \\cite{snell2025scaling, brown2024monkeys} and reward-free selectors \\cite{taubenfeld2025cisc, kang2025selfcertainty, kim2026reasc, wang2025rankedvoting, oh2026latentsc} all rely on answer-level agreement; \\citet{feng2025optimal} and \\citet{wang2025make} adapt to difficulty-aware settings; \\citet{li2025llms} propose generative self-aggregation for IE but focus on fusion rather than selection.\nWe extend self-consistency to set-valued structured outputs and identify the correlation-selection gap.\n\n\\paragraph{Consistency for structured IE.}\n\\citet{yao2026consistency} show consistency correlates with accuracy for LLM-based NER/RE; we show correlation is necessary but not sufficient, diagnosing degeneracy and compression as blocking mechanisms.\nOur experiments use fine-tuned models, where degeneracy is most pronounced and is modulated by task structure and training convergence (Appendix~\\ref{app:epoch_confound}).\nCoCoA \\cite{vashurin2025cocoa} fuses confidence with consistency for QA/summarization; our supervised verifier baseline (\\S\\ref{sec:robustness_main}) suggests combination strategy is not the bottleneck.\nEarlier work on confidence for structured prediction \\cite{culotta2004confidence, mejer2010confidence, fomicheva2020unsupervised} establishes the paradigm we extend to set-valued outputs.\nOur evaluation builds on generative IE \\cite{zhou2024uniner, sainz2024gollie, li2023codeie, wadhwa2023revisiting} and constrained decoding \\cite{willard2023guided, park2024grammar, schall2025hidden, yun2025price}.\n\n\\paragraph{Uncertainty estimation and MBR decoding.}\nSurveys cover confidence estimation \\cite{geng2024confidence}, uncertainty quantification \\cite{xia2025survey}, and calibration \\cite{hobelsberger2025systematic}; semantic uncertainty \\cite{kuhn2023semantic} and P(True) \\cite{kadavath2022language} provide model-internal alternatives.\nOur selection strategies instantiate MBR decoding \\cite{eikema2022sampling, deguchi2024centroid}; unlike MT where MBR yields consistent gains \\cite{freitag2022high} and code generation where execution-based MBR improves selection \\cite{shi2022mbr}, instance degeneracy eliminates the headroom MBR needs even when utility is well-aligned ($\\rho{=}0.52$; \\S\\ref{sec:discussion}).\n\\citet{eikema2025structured} find MBR utilities degrade on structured outputs; our diagnosis is complementary: degeneracy, not utility misalignment, is the primary bottleneck.\nOur QE results connect to selective prediction \\cite{kuleshov2015calibrated}: signals with AUROC up to 0.82 support abstention policies independent of sample selection.\n\n\\paragraph{Best-of-$N$ with learned verifiers.}\n\\citet{gao2023scaling} establish BoN scaling laws; our unsupervised signals face a more fundamental limitation than reward overoptimization.\nTrained verifiers \\cite{cobbe2021verifiers, lightman2024verify, fernandes2022quality} learn per-sample scoring; reward model ensembles mitigate but do not eliminate reward hacking \\cite{eisenstein2023helping}. Our LoRA-rank ablation (degeneracy 7.2\\%, selection still shows no improvement at $\\rho{\\approx}0.24$) suggests that, within the five unsupervised signals studied, increasing output diversity alone is insufficient.\nFine-tuning contributes to degeneracy, analogous to diversity collapse in RLHF \\cite{kirk2024understanding}; constrained structured outputs limit the diversity that temperature scaling \\cite{holtzman2020curious} or diverse decoding \\cite{vijayakumar2018diverse} can recover.\n",
      "numLines": 25,
      "startLine": 1,
      "totalLines": 25
    }
  }
}
```

</details>

---

### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Read · `toolu_01TK5UjQKrnvq7d24d7NDshv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "53dd50d0-f377-41ae-849a-147ceb3533f7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KioYcRTqz3d75hQTPrqcXj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1498,
      "cache_read_input_tokens": 25394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1498
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

_source line 26_

<details open><summary>🔧 Tool call — Read · `toolu_013QTdnVXyuXW8WwqnhTHiKT`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "0078980d-6a76-4ded-9fe3-0b213e58657b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KioYcRTqz3d75hQTPrqcXj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1498,
      "cache_read_input_tokens": 25394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1498
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

_source line 27 · 2026-05-18T05:45:41.086Z_

<details><summary>↩ Tool result · `toolu_013QTdnVXyuXW8WwqnhTHiKT`</summary>

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
11	\usepackage{graphicx}
12	\usepackage{booktabs}
13	\usepackage{amsmath}
14	\usepackage{amssymb}
15	\usepackage{multirow}
16	\usepackage{xcolor}
17	\usepackage{subcaption}
18	
19	\graphicspath{{figures/}}
20	
21	\title{Strong Predictors, Weak Selectors:\\ Why Confidence Signals Fail to Scale Structured Information Extraction}
22	
23	\author{Anonymous}
24	
25	\begin{document}
26	\maketitle
27	
28	\input{sections/abstract}
29	\input{sections/introduction}
30	\input{sections/related_work}
31	\input{sections/method}
32	\input{sections/experiments}
33	\input{sections/discussion}
34	\input{sections/conclusion}
35	
36	\section*{Limitations}
37	\input{sections/limitations}
38	
39	\section*{Ethics Statement}
40	All experiments use publicly available benchmarks (SciERC, CoNLL-2003, WNUT-17) and open-weight models (Qwen3-8B, Qwen3-4B, LLaMA-3.1-8B).
41	CoNLL-2003 is derived from the Reuters RCV1 corpus, which is available for research purposes under a NIST agreement; we use the standard research distribution.
42	No new human data was collected or annotated for this study.
43	Our findings on signal limitations could inform more reliable deployment of IE systems by guiding practitioners toward appropriate confidence signals for their use case.
44	Code and data will be released upon acceptance at [anonymized URL].
45	
46	\bibliography{references}
47	
48	\appendix
49	\input{sections/appendix}
50	
51	\end{document}
52	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "9c0763c3-0efe-47d6-98d8-db95ff6c3958",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/main.tex",
      "content": "\\documentclass[11pt]{article}\n\n\\usepackage[review]{acl}\n\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage{inconsolata}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{multirow}\n\\usepackage{xcolor}\n\\usepackage{subcaption}\n\n\\graphicspath{{figures/}}\n\n\\title{Strong Predictors, Weak Selectors:\\\\ Why Confidence Signals Fail to Scale Structured Information Extraction}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\input{sections/abstract}\n\\input{sections/introduction}\n\\input{sections/related_work}\n\\input{sections/method}\n\\input{sections/experiments}\n\\input{sections/discussion}\n\\input{sections/conclusion}\n\n\\section*{Limitations}\n\\input{sections/limitations}\n\n\\section*{Ethics Statement}\nAll experiments use publicly available benchmarks (SciERC, CoNLL-2003, WNUT-17) and open-weight models (Qwen3-8B, Qwen3-4B, LLaMA-3.1-8B).\nCoNLL-2003 is derived from the Reuters RCV1 corpus, which is available for research purposes under a NIST agreement; we use the standard research distribution.\nNo new human data was collected or annotated for this study.\nOur findings on signal limitations could inform more reliable deployment of IE systems by guiding practitioners toward appropriate confidence signals for their use case.\nCode and data will be released upon acceptance at [anonymized URL].\n\n\\bibliography{references}\n\n\\appendix\n\\input{sections/appendix}\n\n\\end{document}\n",
      "numLines": 52,
      "startLine": 1,
      "totalLines": 52
    }
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-18T05:45:41.269Z_

<details><summary>↩ Tool result · reported error · `toolu_01TK5UjQKrnvq7d24d7NDshv`</summary>

```text
File content (35137 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "26177f29-73d4-4aa6-98d1-403788ed3a73",
  "tool_use_result": "Error: File content (35137 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file."
}
```

</details>

---

### Assistant

_source line 29_

<details><summary>Logged reasoning block</summary>

```text
Now I need to read the appendix file which was too large. Let me read it in chunks to extract all quantitative claims. Let me also run the grep searches for old values.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "11a0f457-f7cf-451f-90ae-db820302b38e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MN9CfjJJuXLHcqxMJrhzsF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 618,
      "cache_creation_input_tokens": 15363,
      "cache_read_input_tokens": 26892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15363
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

_source line 30_

Appendix 太大，需要分段读取。同时搜索旧值残留。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "42999590-9239-4140-be93-5d6ff4c5c453",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MN9CfjJJuXLHcqxMJrhzsF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 618,
      "cache_creation_input_tokens": 15363,
      "cache_read_input_tokens": 26892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15363
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

_source line 31_

<details open><summary>🔧 Tool call — Read · `toolu_011gt4eGhacbmzdegKnNk4Kb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "limit": 500
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "9afd5887-b4bc-47d3-9149-8a10ad5d5faf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MN9CfjJJuXLHcqxMJrhzsF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 618,
      "cache_creation_input_tokens": 15363,
      "cache_read_input_tokens": 26892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15363
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

_source line 32 · 2026-05-18T05:45:47.768Z_

<details><summary>↩ Tool result · `toolu_011gt4eGhacbmzdegKnNk4Kb`</summary>

```text
1	\section{Notation}\label{app:notation}
2	
3	Table~\ref{tab:notation} summarizes the notation used throughout the paper.
4	
5	\begin{table}[h]
6	\centering
7	\small
8	\begin{tabular}{cl}
9	\toprule
10	Symbol & Meaning \\
11	\midrule
12	$\mathcal{M}$ & Language model \\
13	$x$ & Input instance \\
14	$y_i$ & $i$-th stochastic sample \\
15	$N$ & Number of samples \\
16	$T$ & Sampling temperature \\
17	$c(\cdot)$ & Confidence signal \\
18	SJ & Soft Jaccard similarity \\
19	FK & Fleiss' $\kappa$ \\
20	EM & Exact-match voting rate \\
21	VC ($c_{\mathrm{vc}}$) & Entity voting confidence \\
22	LP ($c_{\mathrm{lp}}$) & Log-probability (mean token log-likelihood) \\
23	\bottomrule
24	\end{tabular}
25	\caption{Notation used throughout the paper.}
26	\label{tab:notation}
27	\end{table}
28	
29	\section{Robustness Analysis}\label{app:robustness}
30	
31	We exclude instances with empty gold annotations from all correlation analyses (CoNLL: 697/3{,}453 instances, 20.2\%; SciERC: 22/551, 4.0\%).
32	For these instances, F1 is trivially zero regardless of prediction quality, and consistency signals reflect agreement on the empty set rather than extraction quality. Including them inflates or deflates Spearman $\rho$ depending on signal behavior at the boundary.
33	
34	\begin{table}[t]
35	\centering
36	\small
37	\caption{Signal robustness across configurations (Spearman $\rho$). Top: temperature on Qwen SciERC. Middle: sample size on Qwen SciERC. Bottom: transfer across model families (both 8B) (LLaMA CoNLL $N{=}16$, 3-seed mean $\pm\sigma$). $^\dagger$Mean over 3 seeds ($\sigma{=}0.013$; individual: 0.398, 0.423, 0.410). $\sigma$ computed as sample standard deviation.}
38	\label{tab:robustness}
39	\begin{tabular}{llcc}
40	\toprule
41	& & NER $\rho$ & RE $\rho$ \\
42	\midrule
43	\multicolumn{4}{l}{\textit{Temperature} (Qwen SciERC, $N{=}8$)} \\
44	\quad SJ & $T{=}0.7$ & 0.364 & 0.234 \\
45	\quad SJ & $T{=}1.0$ & 0.360 & 0.250 \\
46	\quad FK & $T{=}0.7$ & 0.289 & 0.184 \\
47	\quad FK & $T{=}1.0$ & 0.267 & 0.275 \\
48	\quad LP & $T{=}0.7$ & 0.249 & --- \\
49	\quad LP & $T{=}1.0$ & 0.205 & 0.266 \\
50	\midrule
51	\multicolumn{4}{l}{\textit{Sample size} (Qwen SciERC, $T{=}1.0$)} \\
52	\quad SJ & $N{=}8$  & 0.360 & 0.250 \\
53	\quad SJ & $N{=}16$ & 0.411$^\dagger$ & 0.281 \\
54	\quad FK & $N{=}8$  & 0.267 & 0.275 \\
55	\quad FK & $N{=}16$ & 0.283 & 0.279 \\
56	\midrule
57	\multicolumn{4}{l}{\textit{Across model families} (LLaMA CoNLL, $N{=}16$, 3 seeds)} \\
58	\quad SJ &  & $0.474{\pm}0.009$ & --- \\
59	\quad FK &  & $0.467{\pm}0.009$ & --- \\
60	\quad EM &  & $0.473{\pm}0.010$ & --- \\
61	\quad VC &  & $0.470{\pm}0.006$ & --- \\
62	\quad LP &  & $0.311{\pm}0.003$ & --- \\
63	\bottomrule
64	\end{tabular}
65	\end{table}
66	
67	\begin{figure}[t]
68	\centering
69	\includegraphics[width=\columnwidth]{fig_temperature_robustness}
70	\caption{Temperature robustness on SciERC ($N{=}8$). Top: NER; bottom: RE. SJ maintains stable $\rho$ across $T{=}0.7$ and $T{=}1.0$, while FK shows mixed sensitivity. LP shows the largest NER temperature effect ($\Delta\rho{=}{+}0.044$); RE $T{=}0.7$ LP data unavailable.}
71	\label{fig:temperature_robustness}
72	\end{figure}
73	
74	\paragraph{Temperature sensitivity.}
75	SJ NER $\rho$ shifts from 0.364 ($T{=}0.7$) to 0.360 ($T{=}1.0$), a difference of 0.004.
76	FK NER $\rho$ drops by 0.022, while RE $\rho$ increases by 0.091, likely reflecting reduced diversity at lower temperature interacting differently across tasks.
77	LP exhibits the largest temperature effect on NER ($\rho{=}0.249$ at $T{=}0.7$ vs.\ $0.205$ at $T{=}1.0$, $\Delta{=}{+}0.044$), consistent with lower temperature concentrating probability mass and improving LP's discriminative power for quality estimation; RE $T{=}0.7$ LP data is not available.
78	Across all comparisons, the signal hierarchy is preserved at both temperatures on NER (SJ${>}$FK${>}$LP at $T{=}0.7$: $0.364{>}0.289{>}0.249$; at $T{=}1.0$: $0.360{>}0.267{>}0.205$).
79	
80	\paragraph{Sample size scaling.}
81	Increasing from $N{=}8$ to $N{=}16$ improves SJ on Qwen SciERC NER: $\rho$ rises from 0.360 to $0.411{\pm}0.010$ (three seeds: 0.398, 0.423, 0.410), a gain of $+0.047$.
82	The magnitude of $N$-scaling gains is setting-dependent (LLaMA SciERC NER yields $+0.016$ and Qwen CoNLL NER $+0.014$), though the direction is consistently positive.
83	LLaMA CoNLL exhibits the most uniform scaling: all four consistency signals gain $\Delta\rho{\approx}{+}0.042$ (range: $+0.039$ to $+0.044$) while LP gains only $+0.004$ (Table~\ref{tab:quality_estimation}).
84	FK $N$-scaling is seed-dependent: Qwen SciERC gains range from $+0.005$ to $+0.023$ across seeds (mean $+0.016$), while LLaMA CoNLL yields $+0.039$ (3-seed mean); individual seed FK shifts vary substantially under the unified pipeline, so this should not be interpreted as a robust trend.
85	VC $N$-scaling is consistently positive ($+0.005$ on Qwen CoNLL, $+0.018$ on LLaMA SciERC, $+0.030$ on Qwen SciERC), while LP is approximately $N$-invariant ($\Delta{\leq}0.034$).
86	SJ, EM, and VC scale consistently across all tested settings; only FK shows seed-dependent variation that does not constitute a reliable trend, structural and binary-agreement signals are the most robust to $N$.
87	At $N{=}16$, SJ converges to comparable NER performance with VC ($\Delta{=}0.002$) while exhibiting lower cross-seed variance ($\sigma{=}0.010$ vs.\ $0.026$), a more stable alternative at higher sample sizes.
88	
89	\paragraph{Transfer across model families.}
90	LLaMA-3.1-8B-Instruct shows a similar SJ--FK ordering on SciERC NER (SJ $\rho{=}0.325{\pm}0.021$, FK $\rho{=}0.256{\pm}0.024$, $\Delta\rho{=}0.069$; permutation $p{=}0.06$, borderline).
91	On CoNLL, the gap across model families is minimal (Table~\ref{tab:quality_estimation}): SJ achieves $\rho{=}0.431$ (LLaMA) vs.\ 0.436 (Qwen), $\Delta{=}0.005$.
92	At $N{=}16$, the structural-over-LP advantage holds across all four tested NER settings: Qwen SciERC (VC $\rho{=}0.409$ vs.\ LP 0.239, $\Delta{=}{+}0.170$), Qwen CoNLL (EM $\rho{=}0.463$ vs.\ LP 0.328, $\Delta{=}{+}0.135$),\footnote{Qwen CoNLL $N{=}16$ was not recomputed under the unified pipeline; LP $\rho{=}0.328$ may differ slightly from the registry value (0.315) due to instance filtering.} LLaMA SciERC (VC $\rho{=}0.452$ vs.\ LP 0.277, $\Delta{=}{+}0.175$), and LLaMA CoNLL 3-seed (SJ $\rho{=}0.474{\pm}0.009$ vs.\ LP $0.311{\pm}0.003$, $\Delta{=}{+}0.163$).
93	
94	\paragraph{FK independence: instance-level permutation test.}\label{app:fk_independence}
95	
96	To verify that Fleiss' $\kappa$ reflects genuine within-instance agreement rather than marginal-rate artifacts, we conduct instance-level permutation tests across three configurations.
97	For each instance, we permute sample labels 10{,}000 times to generate a null distribution of FK under independence, then compare the observed FK against this null via a one-sample $t$-test and permutation $p$-value.
98	
99	\begin{table}[t]
100	\centering
101	\small
102	\caption{Instance-level FK independence test. Permutation tests confirm FK reflects true within-instance agreement (all $p{<}0.001$). Split-half reliability $r$ computed by randomly partitioning $N$ samples into two halves and correlating their FK scores.}
103	\label{tab:fk_independence}
104	\begin{tabular}{lrcccc}
105	\toprule
106	Config & $n$ & FK mean & 95\% CI & $t$ & Split-half $r$ \\
107	\midrule
108	SciERC (Qwen) & 529 & 0.402 & [0.376, 0.428] & 30.8 & 0.395 \\
109	CoNLL (LLaMA) & 2{,}756 & 0.927 & [0.919, 0.935] & 225.9 & 0.578 \\
110	CoNLL (Qwen) & 2{,}756 & 0.720 & [0.706, 0.734] & 102.1 & 0.520 \\
111	\bottomrule
112	\end{tabular}
113	\end{table}
114	
115	Table~\ref{tab:fk_independence} reports the results.
116	All configurations reject the independence null at $p{<}0.001$ ($n{=}529$--$2{,}756$), FK captures genuine inter-sample agreement rather than chance label co-occurrence.
117	Split-half reliability ranges from $r{=}0.395$ (SciERC) to $r{=}0.578$ (CoNLL LLaMA), moderate stability: FK estimates from half the samples correlate positively with those from the other half, though the SciERC value suggests noisier estimation on harder tasks with fewer samples.
118	The higher FK means on CoNLL ($0.720$--$0.927$) vs.\ SciERC ($0.402$) mirror the difficulty gradient observed in the main quality estimation results.
119	
120	\section{Calibration Analysis}\label{app:calibration}
121	
122	\begin{figure*}[t]
123	\centering
124	\includegraphics[width=\textwidth]{fig_reliability}
125	\caption{Reliability diagrams on SciERC ($N{=}8$, $T{=}1.0$). Top: mean F1 vs.\ binned confidence; bottom: instance counts per bin. Left: NER; right: RE. NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE shows greater miscalibration (ECE 0.109--0.339), RE calibration remains challenging for compound extraction tasks.}
126	\label{fig:reliability}
127	\end{figure*}
128	
129	Reliability diagrams use 10 equal-width bins.
130	NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE exhibits greater miscalibration (ECE 0.109--0.339), translating consistency scores into calibrated confidence estimates is feasible for NER but remains challenging for compound extraction tasks.
131	
132	\section{Additional Analyses}\label{app:additional}
133	
134	\begin{figure*}[t]
135	\centering
136	\includegraphics[width=\textwidth]{fig_signal_heatmap}
137	\caption{Quality estimation heatmap (Spearman $\rho$) across five signals and four configurations. Left: full evaluation set; right: conditional set (non-zero F1 instances). On the full set, structural signals dominate on SciERC NER while all signals converge on CoNLL. On the conditional set, EM emerges as the strongest signal on both NER ($\rho{=}0.360$) and RE ($\rho{=}0.417$), while LP RE collapses to near-zero ($\rho{=}0.011$).}
138	\label{fig:signal_heatmap}
139	\end{figure*}
140	
141	\paragraph{Per-relation diagnostic.}
142	RE signal degradation is relation-specific.
143	\textsc{Feature-Of} has near-zero correlation ($\rho{=}0.004$), while \textsc{Hyponym-Of} achieves $\rho{=}0.646$.
144	The primary bottleneck is entity span errors, which account for 55.5\% of RE false negatives. This is a prerequisite failure that consistency signals cannot detect, as they measure agreement among equally incorrect extractions.
145	We note that RE analysis relies on a single dataset (SciERC); generalization to other RE benchmarks remains to be validated.
146	
147	\paragraph{Capability stratification.}
148	For NER, SJ effectiveness scales with structural complexity: on SciERC instances with 6+ entities, $\rho{=}0.547$, compared to $\rho{=}0.415$ for 1--2 entities.
149	The SJ advantage over LP remains stable across sentence-length quartiles ($\Delta\rho{\approx}0.08$--$0.20$).
150	For RE, SJ $\rho$ increases monotonically with sentence length (Q1: 0.110 $\to$ Q4: 0.473; Fisher $z$-test $p{=}0.004$): longer, more relation-dense sentences provide richer structure for consistency-based estimation.
151	Both proxies are weakly correlated with F1 ($|r|{<}0.15$), they capture input complexity rather than directly predicting output quality; however, entity count and sentence length are themselves moderately correlated ($\rho{=}0.650$), so they reflect overlapping rather than independent complexity dimensions.
152	For RE, entity count and relation count are strongly correlated ($\rho{=}0.769$) and thus reflect a single structural complexity dimension rather than independent axes.
153	On the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\rho{=}0.630$, LP $\rho{=}0.554$, and SJ $\rho{=}0.502$, all far above the full-set levels.
154	Richer relational structure provides more signal for consistency-based estimation, complementing the task-level boundary established by WNUT-17: structural signals are most effective within a ``sweet spot'' of sufficient model capability and sufficient output complexity.
155	
156	\paragraph{Length vs.\ log-probability.}
157	Figure~\ref{fig:length_logprob_scatter} shows that mean log-probability is weakly positively correlated with output length (NER: $\rho{=}0.386$, $n{=}4{,}232$; RE: $\rho{=}0.326$, $n{=}3{,}176$), ruling out length-penalty confounding as an explanation for LP's selection failure: longer outputs receive \textit{higher}, not lower, token-averaged log-probability under constrained decoding.
158	
159	\begin{figure}[t]
160	\centering
161	\includegraphics[width=\columnwidth]{fig_length_logprob_scatter}
162	\caption{Output length vs.\ mean log-probability on SciERC ($N{=}8$, $T{=}1.0$). Positive correlations (NER: $\rho{=}0.386$; RE: $\rho{=}0.326$) rule out length-penalty confounding.}
163	\label{fig:length_logprob_scatter}
164	\end{figure}
165	
166	\paragraph{Evaluation circularity and LOO-SJ equivalence.}
167	Consensus-proximity selection chooses $\hat{y} = \arg\max_{y_i} \sum_{j \neq i} \text{SJ}(y_i, y_j)$.
168	Leave-one-out SJ (LOO-SJ) for sample $y_i$ is $\text{LOO-SJ}_i = \frac{1}{N-1}\sum_{j \neq i} \text{SJ}(y_i, y_j)$.
169	Since the $\frac{1}{N-1}$ constant is shared across all candidates within an instance, $\arg\max_{y_i} \text{LOO-SJ}_i = \arg\max_{y_i} \sum_{j \neq i} \text{SJ}(y_i, y_j)$; the two selection rules are equivalent.
170	Standard (non-LOO) SJ adds the self-comparison term $\text{SJ}(y_i, y_i) = 1$ to each candidate, which is constant and thus does not affect ranking.
171	Empirically, LOO-SJ yields $\Delta\rho{=}{-}0.014$ relative to standard SJ (a correlation-level difference), with a maximum per-instance score difference of $3.1{\times}10^{-4}$ (negligible at the individual prediction level).
172	Evaluation circularity is negligible.
173	
174	\paragraph{SJ normalizer robustness.}
175	Equation~\ref{eq:sj} uses $\max(|g_i|, |g_j|)$ as the denominator; an alternative is the union size $|g_i \cup g_j|$.
176	Table~\ref{tab:sj_normalizer} compares the two normalizers across all six model--dataset combinations ($N{=}8$, $T{=}1.0$, seed${=}42$): $|\Delta\rho|{<}0.01$ in every case, the choice between max and union normalization does not affect conclusions.
177	
178	\begin{table}[h]
179	\centering
180	\small
181	\caption{SJ normalizer comparison (Spearman $\rho$; $N{=}8$, $T{=}1.0$, seed${=}42$). Max: $\max(|g_i|,|g_j|)$; Union: $|g_i \cup g_j|$.}
182	\label{tab:sj_normalizer}
183	\begin{tabular}{@{}ll ccc@{}}
184	\toprule
185	Dataset & Model & $\rho$(max) & $\rho$(union) & $\Delta\rho$ \\
186	\midrule
187	CoNLL & Qwen3-8B & .436 & .438 & $-$.002 \\
188	CoNLL & Qwen3-4B & .422 & .421 & $+$.000 \\
189	CoNLL & LLaMA-8B & .431 & .432 & $-$.000 \\
190	SciERC & Qwen3-8B & .360 & .365 & $-$.005 \\
191	SciERC & Qwen3-4B & .422 & .423 & $-$.001 \\
192	SciERC & LLaMA-8B & .363 & .372 & $-$.009 \\
193	\bottomrule
194	\end{tabular}
195	\end{table}
196	
197	\paragraph{Conditional filtering details.}
198	On LLaMA conditional RE (non-zero F1 instances), SJ recovers to $\rho{=}0.405$ while FK drops to $\rho{=}0.259$, consistent with the NER structural advantage; on full-set RE, however, the SJ--FK difference is non-significant ($\Delta\rho{=}{-}0.005$, $p{=}0.53$; preliminary).
199	At $N{=}16$, the divergence persists: SJ maintains $\rho{=}0.308$ on conditional RE while LP drops to $\rho{=}{-}0.026$.
200	EM ranks first across all four tested conditional configurations: SciERC NER ($\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\rho{=}0.466$), CoNLL LLaMA 3-seed ($\rho{=}0.462$), and SciERC RE ($\rho{=}0.417$). This holds despite full-set rankings ranging from \#1 (CoNLL Qwen) to \#5 (SciERC RE).
201	On the full set, EM is diluted by trivial agreement: instances where all $N$ samples produce identical (possibly incorrect) outputs receive EM${=}1$ regardless of quality, compressing the signal's dynamic range.
202	On the conditional set, where the model demonstrably produces varied outputs, exact agreement becomes the strongest quality signal.
203	The margin over SJ is largest on RE ($\Delta\rho{=}{+}0.171$), where compound extraction decisions amplify output variability, and smallest on CoNLL LLaMA ($\Delta\rho{=}{+}0.002$), where all signals converge near $\rho{\approx}0.46$.
204	
205	\paragraph{WNUT-17 full signal analysis.}
206	Table~\ref{tab:wnut} reports all five signals on WNUT-17 with full-set and conditional $\rho$.
207	
208	\begin{table}[t]
209	\centering
210	\small
211	\caption{Quality estimation on WNUT-17 (Qwen, $N{=}16$, $T{=}1.0$, $n{=}689$). Cond: non-zero F1 instances ($n{=}334$). Full-set $\rho$ reflects binary success prediction; conditional $\rho$ measures quality gradation. LP's conditional $\rho$ is highest despite negative full-set $\rho$.}
212	\label{tab:wnut}
213	\begin{tabular}{lcccc}
214	\toprule
215	Signal & $\rho$ & AUROC & Cond.\ $\rho$ & Cond.\ $p$ \\
216	\midrule
217	VC      & .724 & .913 & .038 & .487 \\
218	FK      & .125 & .555 & .169 & .002 \\
219	SJ      & .089 & .517 & .288 & ${<}$1e-7 \\
220	EM      & .050 & .487 & .333 & ${<}$1e-9 \\
221	LP & $-$.410 & .219 & .350 & ${<}$1e-10 \\
222	\bottomrule
223	\end{tabular}
224	\end{table}
225	The full-set $p$-values are: VC ${<}$1e-112, FK $p{=}0.001$, SJ $p{=}0.020$, EM $p{=}0.194$, LP ${<}$1e-28.
226	VC's high full-set $\rho{=}0.724$ is entirely driven by the zero/non-zero boundary (conditional $\rho{=}0.038$, $p{=}0.49$), while LP's conditional $\rho{=}0.350$ is the highest among all signals on the non-zero subset, full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.
227	
228	\paragraph{Cross-configuration selection analysis.}
229	Table~\ref{tab:cross_selection} extends the selection analysis to four additional configurations.
230	On LLaMA SciERC, where output diversity remains substantial (18\% identical outputs, 39\% unique), LP achieves the highest selection F1 (0.652) at $N{=}8$ but still falls within bootstrap noise of single-sample (0.646), replicating the gap observed on Qwen SciERC (Table~\ref{tab:selection}).
231	On CoNLL, 57--88\% of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect (single-sample F1 ${\approx}$0.91--0.92) rather than signal failure, and selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.
232	
233	\begin{table*}[t]
234	\centering
235	\small
236	\caption{Best-of-$N$ selection F1 (macro, instance-averaged) across configurations ($T{=}1.0$). Best non-oracle signal per row in \textbf{bold}. At $N{=}8$, no signal significantly outperforms greedy in any configuration. At $N{=}16$ on LLaMA CoNLL, VC achieves small but significant gains ($+0.28$~pp, $p{<}0.03$; see text below). CoNLL shows especially tight clustering where greedy already exceeds 0.90.}
237	\label{tab:cross_selection}
238	\begin{tabular}{llccccccc}
239	\toprule
240	Config & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\
241	\midrule
242	LLaMA/SciERC $N{=}8$ & 529 & .646 & .778 & .643 & .639 & .634 & \textbf{.652} & .633 \\
243	LLaMA/SciERC $N{=}16$ & 529 & .645 & .806 & \textbf{.649} & \textbf{.649} & .640 & .646 & .640 \\
244	Qwen/CoNLL $N{=}8$ & 2{,}756 & .908 & .948 & \textbf{.899} & .893 & .898 & .897 & .895 \\
245	LLaMA/CoNLL $N{=}8$ & 2{,}756 & .924 & .943 & .924 & \textbf{.925} & .924 & .924 & .923 \\
246	\bottomrule
247	\end{tabular}
248	\end{table*}
249	
250	\paragraph{Diminishing returns of $N$-scaling.}
251	Our $N{=}8$ and $N{=}16$ comparisons (Table~\ref{tab:robustness}) characterize the marginal value of additional samples for test-time scaling \cite{brown2024monkeys, snell2025scaling}.
252	For quality estimation, structural signals benefit consistently but sublinearly: SJ $\rho$ improves by $+0.047$ (Qwen SciERC, 3-seed mean) and $+0.032$ (LLaMA CoNLL, 3-seed mean) when doubling from $N{=}8$ to $N{=}16$, while log-probability is approximately $N$-invariant ($\Delta\rho{\leq}0.021$).
253	Structural signals use $\binom{N}{2}$ pairwise comparisons (28 pairs at $N{=}8$, 120 at $N{=}16$), but the $\rho$ improvement is far less than proportional, each additional comparison yields diminishing information.
254	This asymmetry gives structural signals a relative advantage in the compute-constrained regime: at $N{=}8$, SJ already achieves $\rho{=}0.431$ on LLaMA CoNLL (vs.\ LP $\rho{=}0.307$, $\Delta{=}{+}0.124$), and the gap \textit{widens} at $N{=}16$ ($\Delta{=}{+}0.163$) because structural signals continue to benefit from additional pairwise evidence while LP does not.
255	For sample selection, additional samples increase the oracle upper bound (more draws raise the probability of a high-quality candidate), but signal-based selection remains flat because the selector's inability to identify the best candidate is a granularity limitation, not a sample size limitation.
256	The practical implication is that $N{=}8$ captures most of the achievable quality estimation benefit; further scaling widens rather than closes the correlation-selection gap absent stronger per-sample selectors.
257	
258	\paragraph{$N{=}16$ CoNLL selection: small but significant.}
259	While quality estimation benefits sublinearly from $N$-scaling, selection behavior at $N{=}16$ reveals a nuanced exception on LLaMA CoNLL.
260	VC achieves the largest gain over single-sample ($+0.28$~pp, $p{=}0.003$--$0.027$ across 3 seeds, all significant), with SJ, FK, and EM at $+0.22$--$0.23$~pp and LP at $+0.12$~pp (2/3 seeds significant).
261	These gains are statistically significant but practically minimal: oracle headroom at $N{=}16$ is only 2.5~pp, so VC captures approximately 10\% of the available headroom.
262	This reinforces the primary finding: even under the most favorable conditions (high baseline performance, more candidates, and aggregated multi-seed evidence), signal-based selection recovers only a fraction of the oracle headroom available.
263	
264	\section{Bootstrap CI for Signal Comparisons}\label{app:bootstrap_signal}
265	
266	Table~\ref{tab:bootstrap_signal_ci} reports bootstrap confidence intervals for individual signal $\rho$ and pairwise $\Delta\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$).
267	The SJ--LP gap ($\Delta\rho{=}{+}0.155$) is clearly significant, the structural advantage reported in \S\ref{sec:qe_results} is robust.
268	The VC--SJ gap ($\Delta\rho{=}{+}0.019$) is not significant; these two structural signals perform comparably.
269	The SJ--EM gap ($\Delta\rho{=}{+}0.065$) is borderline significant, with the CI lower bound at $+0.003$ and upper bound at $+0.130$.
270	
271	\begin{table}[t]
272	\centering
273	\small
274	\caption{Bootstrap 95\% CIs for signal $\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$). Top: individual signals. Bottom: pairwise $\Delta\rho$; ``Sig.'' indicates whether the 95\% CI excludes zero.}
275	\label{tab:bootstrap_signal_ci}
276	\begin{tabular}{lcc}
277	\toprule
278	Signal & $\rho$ & 95\% CI \\
279	\midrule
280	VC & +0.379 & [+0.299, +0.456] \\
281	SJ & +0.360 & [+0.277, +0.437] \\
282	EM & +0.295 & [+0.212, +0.371] \\
283	FK & +0.267 & [+0.176, +0.354] \\
284	LP & +0.205 & [+0.119, +0.291] \\
285	\bottomrule
286	\end{tabular}
287	
288	\vspace{0.5em}
289	
290	\begin{tabular}{lccc}
291	\toprule
292	Comparison & $\Delta\rho$ & 95\% CI & Sig. \\
293	\midrule
294	SJ $-$ LP & +0.155 & [+0.074, +0.234] & Yes \\
295	VC $-$ SJ & +0.019 & [$-$0.033, +0.073] & No \\
296	SJ $-$ EM & +0.065 & [+0.003, +0.130] & Marginal$^\dagger$ \\
297	\bottomrule
298	\end{tabular}
299	
300	\smallskip
301	{\footnotesize $^\dagger$Marginally significant without multiple comparison correction; would not survive Bonferroni correction for 10 pairwise comparisons ($\alpha_{\text{adj}}{=}0.005$).}
302	\end{table}
303	
304	At $N{=}16$ ($B{=}10{,}000$, permutation test), the structural advantage extends to FK comparisons.
305	On SciERC NER ($n{=}529$), SJ--FK ($\Delta\rho{=}0.147$--$0.160$, all $p{\leq}0.002$) and VC--FK ($\Delta\rho{=}0.138$--$0.188$, all $p{\leq}0.003$) are clearly significant across all three seeds; EM--FK is seed-dependent ($\Delta\rho{=}0.054$--$0.093$, $p{=}0.048$--$0.15$).
306	On CoNLL ($n{=}2{,}756$), all signals significantly outperform FK: EM $\Delta\rho{=}0.071$ ($p{<}0.001$), SJ $\Delta\rho{=}0.056$ ($p{<}0.001$), VC $\Delta\rho{=}0.022$ ($p{=}0.040$).
307	
308	\section{Diversity and Selection Analysis}\label{app:diversity}
309	
310	\begin{figure*}[t]
311	\centering
312	\includegraphics[width=\textwidth]{fig_selection_gap}
313	\caption{The correlation-selection gap on SciERC NER ($N{=}8$, $T{=}1.0$, 2-seed mean). Bars show best-of-$N$ selection F1; the line marks quality estimation $\rho$. Despite $\rho$ up to 0.40, no signal significantly outperforms single-sample (all $p{>}0.05$; Table~\ref{tab:selection}). Dashed line indicates oracle upper bound. RE selection results in Table~\ref{tab:selection}.}
314	\label{fig:selection_gap}
315	\end{figure*}
316	
317	\paragraph{Output diversity quantification.}
318	Table~\ref{tab:diversity} summarizes output diversity across configurations.
319	On SciERC, output diversity is substantial: Qwen produces 43\% unique outputs per instance (mean 3.5 distinct out of $N{=}8$), with per-sample F1 standard deviation of 0.144 and mean pairwise SJ of 0.703.
320	LLaMA shows similar diversity (39\% unique, F1 std 0.11).
321	On CoNLL, diversity collapses: 57\% (Qwen) to 88\% (LLaMA) of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect where single-sample F1 already exceeds 0.90.
322	WNUT-17 shows 55\% identical outputs, driven by the 52\% zero-F1 rate.
323	
324	\begin{table}[t]
325	\centering
326	\small
327	\caption{Output diversity across configurations ($N{=}8$, $T{=}1.0$). ``Identical'' = fraction of instances with all $N$ outputs identical. ``Unique'' = mean fraction of distinct outputs per instance.}
328	\label{tab:diversity}
329	\begin{tabular}{lcc}
330	\toprule
331	Config & Identical & Unique \\
332	\midrule
333	Qwen/SciERC & 11\% & 43\% \\
334	LLaMA/SciERC & 18\% & 39\% \\
335	Qwen/CoNLL & 57\% & --- \\
336	LLaMA/CoNLL & 88\% & --- \\
337	WNUT-17 & 55\% & --- \\
338	\bottomrule
339	\end{tabular}
340	\end{table}
341	
342	\paragraph{Oracle-improvable fraction.}
343	Across SciERC configurations, 39--42\% of instances contain at least one sample with F1 exceeding single-sample\footnote{Oracle-improvable and diversity-stratified analyses use $n{=}529$ (excluding instances with empty gold annotations; see \S\ref{sec:evaluation}); the diversity quantification in Table~\ref{tab:diversity} uses the full test set.}: Qwen NER 42.0\% (222/529, mean headroom $+$31.9~pp among improvable instances), Qwen RE 41.3\% (164/397, $+$45.3~pp), LLaMA NER 39.3\% (208/529, $+$33.7~pp).
344	On CoNLL, only 4--9\% of instances are improvable, consistent with the ceiling effect.
345	
346	\paragraph{Diversity-stratified selection gap.}
347	On the 44\% of Qwen SciERC instances with high diversity (${\geq}4$ unique outputs among 8 samples, $n{=}232$), oracle headroom reaches $+$16.3~pp, yet all consistency-based signals (SJ, FK, EM, VC) select at or below single-sample, and LP, the only per-sample signal, achieves merely $+$0.8~pp.
348	LLaMA replicates this pattern: on its high-diversity subset ($n{=}186$), oracle headroom reaches $+$20.1~pp while consistency signals remain at or below single-sample and LP captures only $+$2.0~pp.
349	This rules out insufficient diversity as an explanation for the correlation-selection gap.
350	
351	\paragraph{Instance degeneracy statistics.}
352	Table~\ref{tab:degeneracy} quantifies instance degeneracy across configurations. ``Constant F1'' denotes instances where all $N$ samples receive identical instance-level F1; ``Constant utility'' denotes instances where MBR (SJ) utility is identical across candidates, preventing ranking.
353	
354	\begin{table}[t]
355	\centering
356	\small
357	\caption{Instance degeneracy statistics ($T{=}1.0$). ``Constant F1'': all $N$ samples receive identical instance-level F1. ``Constant utility'': MBR (SJ) utility identical across candidates. 4B data confirms degeneracy scales with model capability.}
358	\label{tab:degeneracy}
359	\begin{tabular}{lccc}
360	\toprule
361	& \shortstack{SciERC 8B\\($N{=}8$)} & \shortstack{SciERC 4B\\($N{=}8$)} & \shortstack{CoNLL 8B\\($N{=}16$)} \\
362	\midrule
363	Constant F1 & 17.8\% & 10.4\% & 48.3\% \\
364	Constant utility & 13\% & 7.0\% & 49\% \\
365	Oracle gap closed (non-deg.) & 23\% & 25.2\% & 41\% \\
366	Within-inst.\ SJ $\rho$ (median) & 0.524 & 0.550 & 0.994 \\
367	\bottomrule
368	\end{tabular}
369	\end{table}
370	
371	\paragraph{TOST equivalence testing.}\label{app:tost}
372	The primary evidence against selection gains comes from effect sizes and confidence intervals: Cohen's $d{=}0.038$ for the best signal (NER LP) and bootstrap 95\% CI [$-$3.0, $+$4.2]~pp spanning zero.
373	Table~\ref{tab:tost} supplements this with two one-sided tests (TOST), testing whether each signal's selection F1 is equivalent to single-sample within a bound $\delta$.
374	The $\delta$ values are contextualized against oracle headroom (12--18~pp): $\delta{=}5$~pp corresponds to forgoing 28--38\% of the available headroom, $\delta{=}3$~pp forgoing 17--23\%, and $\delta{=}2$~pp less than 15\%.
375	These proportions use the same test data that defines the headroom, introducing circularity: $\delta$ is anchored to the very quantity it contextualizes.
376	We address this below with externally anchored equivalence margins.
377	The breakpoint $\delta^*$, the minimum equivalence margin at which each signal passes TOST, ranges from approximately 1.3~pp (SJ, ${\sim}$10\% of oracle headroom) to 3.4~pp (FK, ${\sim}$26\%) on NER, and from approximately 2.9~pp (LP, ${\sim}$16\%) to 6.5~pp (VC, ${\sim}$36\%) on RE.
378	On NER ($n{=}529$), at $\delta{=}{\pm}2$~pp, SJ and LP are confirmed equivalent to single-sample (TOST $p{<}0.05$); at $\delta{=}{\pm}3$~pp, four of five signals pass; at $\delta{=}{\pm}5$~pp, all five pass.
379	On RE ($n{=}397$, preliminary), EM and VC fail equivalence even at $\delta{=}{\pm}5$~pp due to systematic underperformance ($\Delta{=}{-}3.2$~pp and $-4.5$~pp respectively).
380	The effect sizes are negligible ($d{=}0.038$) and confidence intervals span zero, with TOST confirming equivalence at practically meaningful margins.
381	
382	\begin{table}[t]
383	\centering
384	\small
385	\caption{TOST equivalence testing: signals vs.\ single-sample on SciERC ($N{=}8$, $T{=}1.0$). \checkmark: equivalent at $p{<}0.05$; \texttimes: not equivalent. $\Delta$: mean F1 difference (signal $-$ single-sample).}
386	\label{tab:tost}
387	\begin{tabular}{l cccc cccc}
388	\toprule
389	& \multicolumn{4}{c}{\textbf{NER}} & \multicolumn{4}{c}{\textbf{RE}} \\
390	\cmidrule(lr){2-5} \cmidrule(lr){6-9}
391	Signal & $\Delta$ & $\pm$2 & $\pm$3 & $\pm$5 & $\Delta$ & $\pm$2 & $\pm$3 & $\pm$5 \\
392	\midrule
393	LP & +0.6 & \checkmark & \checkmark & \checkmark & $-$0.9 & \texttimes & \checkmark & \checkmark \\
394	SJ & +0.1 & \checkmark & \checkmark & \checkmark & $-$1.8 & \texttimes & \texttimes & \checkmark \\
395	FK & $-$0.5 & \texttimes & \checkmark & \checkmark & $-$1.6 & \texttimes & \texttimes & \checkmark \\
396	EM & $-$0.8 & \texttimes & \checkmark & \checkmark & $-$3.2 & \texttimes & \texttimes & \texttimes \\
397	VC & $-$1.0 & \texttimes & \texttimes & \checkmark & $-$4.5 & \texttimes & \texttimes & \texttimes \\
398	\bottomrule
399	\end{tabular}
400	\end{table}
401	
402	\paragraph{External equivalence margins.}
403	The oracle-headroom anchors above introduce circularity, as a reviewer correctly noted: $\delta$ is calibrated against the very quantity it contextualizes.
404	To resolve this, we supplement with three externally grounded margins:
405	(1) $\delta_{\mathrm{SEM}}$: the bootstrapped standard error of single-sample F1 (0.43--1.33~pp depending on configuration), which represents measurement noise;
406	(2) $\delta_{\mathrm{practical}}{=}0.5$~pp, the threshold below which NER differences are considered negligible \cite{ratinov2009design};
407	(3) $\delta_{\mathrm{literature}}{=}1.0$~pp, the approximate significant-difference threshold established in NER evaluation methodology \cite{bergkirkpatrick2012empirical}.
408	
409	Results under these external anchors diverge sharply by configuration.
410	On LLaMA CoNLL ($n{=}2{,}756$), all signals pass equivalence at every $\delta$ ($p{<}0.001$), consistent with the near-zero selection deltas ($|\Delta|{\leq}0.1$~pp) and tight CIs at this sample size.
411	On Qwen CoNLL ($n{=}2{,}756$), no signal passes at any external $\delta$: selection F1 degrades by 0.9--1.5~pp relative to single-sample, which exceeds even $\delta_{\mathrm{literature}}$.
412	On SciERC NER ($n{=}529$), only SJ passes at $\delta_{\mathrm{SEM}}{=}1.33$~pp (the widest SEM bound); all other signals and tighter margins fail.
413	These external anchors confirm that the equivalence conclusion is configuration-dependent: LLaMA CoNLL selection is robustly equivalent to single-sample under any reasonable margin, while SciERC and Qwen CoNLL selection shows detectable degradation at externally calibrated thresholds.
414	
415	\paragraph{Multiple comparison considerations.}\label{app:multiple_comparisons}
416	Our primary selection analysis involves ${\sim}$20 comparisons (5 signals $\times$ 3--4 configurations).
417	Since all primary selection results are non-significant ($p{>}0.05$), applying Benjamini-Hochberg correction can only make these results more conservative, strengthening the ``no signal beats greedy'' conclusion.
418	The sole positive finding, the non-tied LP subset ($+2.9$~pp, $p{=}0.004$; \S\ref{sec:discussion}), survives Bonferroni correction over 5 signal comparisons ($p_{\mathrm{adj}}{=}0.020 < 0.05$), as noted in the main text footnote.
419	For quality estimation signal rankings, differences between the top signals (e.g., VC vs.\ SJ on SciERC) should be interpreted as descriptive rather than as statistically confirmed orderings, given the limited power of 3-seed comparisons.
420	
421	\section{Multi-Seed Stability}\label{app:multiseed}
422	
423	Table~\ref{tab:multiseed} reports quality estimation metrics across three random seeds for both model families on SciERC ($N{=}8$, $T{=}1.0$).
424	On NER, the signal ranking VC${>}$SJ${>}$EM${>}$FK${>}$LP is identical across all six model-seed combinations, with $\sigma{\leq}0.025$ for all signals (rankings are stable across our 3 seeds, though statistical power with $n{=}3$ is limited).
425	On RE (Qwen only, preliminary), VC remains the top signal ($\rho{=}0.309{\pm}0.024$), but LP rises to \#2 ($\rho{=}0.297{\pm}0.022$), above FK, SJ, and EM. This reversal from the NER ranking reflects RE's higher sensitivity to per-sample scoring.
426	LLaMA absolute values are systematically lower than Qwen on NER, consistent with the directionally-consistent-but-magnitude-dependent characterization in the main text.
427	
428	\begin{table}[t]
429	\centering
430	\small
431	\caption{Multi-seed quality estimation on SciERC ($N{=}8$, $T{=}1.0$, seeds: 42, 123, 456). NER: both models; RE: Qwen only (preliminary). Signal ranking is stable across seeds ($\sigma{\leq}0.025$). $\sigma$ is population standard deviation over 3 seeds.}
432	\label{tab:multiseed}
433	\begin{tabular}{lccccc}
434	\toprule
435	& LP & FK & SJ & VC & EM \\
436	\midrule
437	\multicolumn{6}{l}{\textit{NER Spearman $\rho$ (mean $\pm\sigma$)}} \\
438	Qwen & .217${\pm}$.013 & .254${\pm}$.016 & .364${\pm}$.018 & .386${\pm}$.019 & .307${\pm}$.008 \\
439	LLaMA & .162${\pm}$.025 & .256${\pm}$.024 & .325${\pm}$.021 & .384${\pm}$.014 & .279${\pm}$.011 \\
440	\midrule
441	\multicolumn{6}{l}{\textit{RE Spearman $\rho$ (mean $\pm\sigma$, Qwen)}} \\
442	Qwen & .297${\pm}$.022 & .290${\pm}$.012 & .249${\pm}$.002 & .309${\pm}$.024 & .135${\pm}$.016 \\
443	\midrule
444	\multicolumn{6}{l}{\textit{NER AUROC (mean $\pm\sigma$)}} \\
445	Qwen & .579${\pm}$.008 & .600${\pm}$.016 & .659${\pm}$.016 & .677${\pm}$.011 & .631${\pm}$.013 \\
446	LLaMA & .565${\pm}$.008 & .593${\pm}$.006 & .632${\pm}$.012 & .673${\pm}$.009 & .606${\pm}$.005 \\
447	\bottomrule
448	\end{tabular}
449	\end{table}
450	
451	\section{Training Configuration}\label{app:training}
452	
453	Both models are fine-tuned with identical hyperparameters (Table~\ref{tab:training}) to ensure comparisons across model families reflect model differences rather than training confounds.
454	
455	\begin{table}[t]
456	\centering
457	\small
458	\caption{Training configuration. Both Qwen3-8B and LLaMA-3.1-8B-Instruct use identical settings unless noted.}
459	\label{tab:training}
460	\begin{tabular}{ll}
461	\toprule
462	Parameter & Value \\
463	\midrule
464	LoRA rank / $\alpha$ & 32 / 64 \\
465	LoRA target & All linear modules \\
466	LoRA dropout & 0 \\
467	Optimizer & AdamW \\
468	Learning rate & 2e-4, cosine schedule \\
469	Warmup ratio & 0.1 \\
470	Effective batch size & 16 (2 $\times$ grad.\ accum.\ 8) \\
471	Epochs & 5 \\
472	Max sequence length & 2048 \\
473	Precision & bf16 \\
474	Gradient checkpointing & Enabled \\
475	Max gradient norm & 1.0 \\
476	Training seed & 42 \\
477	Framework & LLaMA Factory \\
478	\midrule
479	\multicolumn{2}{l}{\textit{Dataset-specific}} \\
480	SciERC split & 1861 / 275 / 551 \\
481	CoNLL / WNUT & +\,load\_best\_model\_at\_end, \\
482	& eval\_steps${=}$200, save\_limit${=}$5 \\
483	\bottomrule
484	\end{tabular}
485	\end{table}
486	
487	\paragraph{Prompt template.}
488	For NER, we use a structured prompt:
489	\begin{quote}
490	\small
491	\texttt{System:} You are an expert in Named Entity Recognition.\\
492	\texttt{User:} Extract all named entities from the following text. Output as JSON.\\
493	Text: \texttt{\{input\_text\}}\\
494	Entity types: \texttt{\{schema\_types\}}
495	\end{quote}
496	RE follows the same structure with ``Relation Extraction'' and relation type lists substituted accordingly.
497	
498	\paragraph{Constrained decoding.}
499	Inference uses vLLM with XGrammar-based JSON schema enforcement \cite{willard2023guided}, which constrains outputs to valid entity/relation structures matching the target schema.
500	This eliminates format errors but may compress per-sample diversity by restricting the output space.\footnote{SciERC training used \texttt{enable\_thinking=True} (LLaMA Factory 0.9.4 default), injecting empty \texttt{&lt;think>&lt;/think>} blocks (4--5 tokens) into each training response with loss computation; CoNLL and WNUT explicitly set \texttt{enable\_thinking=False}. Constrained decoding at inference time enforces JSON-only output, suppressing thinking tokens. See \S\ref{sec:setup} and Limitations for discussion of this confound.}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "9ea9bf6b-0abf-4618-8630-2d136cf97914",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "\\section{Notation}\\label{app:notation}\n\nTable~\\ref{tab:notation} summarizes the notation used throughout the paper.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{cl}\n\\toprule\nSymbol & Meaning \\\\\n\\midrule\n$\\mathcal{M}$ & Language model \\\\\n$x$ & Input instance \\\\\n$y_i$ & $i$-th stochastic sample \\\\\n$N$ & Number of samples \\\\\n$T$ & Sampling temperature \\\\\n$c(\\cdot)$ & Confidence signal \\\\\nSJ & Soft Jaccard similarity \\\\\nFK & Fleiss' $\\kappa$ \\\\\nEM & Exact-match voting rate \\\\\nVC ($c_{\\mathrm{vc}}$) & Entity voting confidence \\\\\nLP ($c_{\\mathrm{lp}}$) & Log-probability (mean token log-likelihood) \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Notation used throughout the paper.}\n\\label{tab:notation}\n\\end{table}\n\n\\section{Robustness Analysis}\\label{app:robustness}\n\nWe exclude instances with empty gold annotations from all correlation analyses (CoNLL: 697/3{,}453 instances, 20.2\\%; SciERC: 22/551, 4.0\\%).\nFor these instances, F1 is trivially zero regardless of prediction quality, and consistency signals reflect agreement on the empty set rather than extraction quality. Including them inflates or deflates Spearman $\\rho$ depending on signal behavior at the boundary.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Signal robustness across configurations (Spearman $\\rho$). Top: temperature on Qwen SciERC. Middle: sample size on Qwen SciERC. Bottom: transfer across model families (both 8B) (LLaMA CoNLL $N{=}16$, 3-seed mean $\\pm\\sigma$). $^\\dagger$Mean over 3 seeds ($\\sigma{=}0.013$; individual: 0.398, 0.423, 0.410). $\\sigma$ computed as sample standard deviation.}\n\\label{tab:robustness}\n\\begin{tabular}{llcc}\n\\toprule\n& & NER $\\rho$ & RE $\\rho$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Temperature} (Qwen SciERC, $N{=}8$)} \\\\\n\\quad SJ & $T{=}0.7$ & 0.364 & 0.234 \\\\\n\\quad SJ & $T{=}1.0$ & 0.360 & 0.250 \\\\\n\\quad FK & $T{=}0.7$ & 0.289 & 0.184 \\\\\n\\quad FK & $T{=}1.0$ & 0.267 & 0.275 \\\\\n\\quad LP & $T{=}0.7$ & 0.249 & --- \\\\\n\\quad LP & $T{=}1.0$ & 0.205 & 0.266 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Sample size} (Qwen SciERC, $T{=}1.0$)} \\\\\n\\quad SJ & $N{=}8$  & 0.360 & 0.250 \\\\\n\\quad SJ & $N{=}16$ & 0.411$^\\dagger$ & 0.281 \\\\\n\\quad FK & $N{=}8$  & 0.267 & 0.275 \\\\\n\\quad FK & $N{=}16$ & 0.283 & 0.279 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Across model families} (LLaMA CoNLL, $N{=}16$, 3 seeds)} \\\\\n\\quad SJ &  & $0.474{\\pm}0.009$ & --- \\\\\n\\quad FK &  & $0.467{\\pm}0.009$ & --- \\\\\n\\quad EM &  & $0.473{\\pm}0.010$ & --- \\\\\n\\quad VC &  & $0.470{\\pm}0.006$ & --- \\\\\n\\quad LP &  & $0.311{\\pm}0.003$ & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_temperature_robustness}\n\\caption{Temperature robustness on SciERC ($N{=}8$). Top: NER; bottom: RE. SJ maintains stable $\\rho$ across $T{=}0.7$ and $T{=}1.0$, while FK shows mixed sensitivity. LP shows the largest NER temperature effect ($\\Delta\\rho{=}{+}0.044$); RE $T{=}0.7$ LP data unavailable.}\n\\label{fig:temperature_robustness}\n\\end{figure}\n\n\\paragraph{Temperature sensitivity.}\nSJ NER $\\rho$ shifts from 0.364 ($T{=}0.7$) to 0.360 ($T{=}1.0$), a difference of 0.004.\nFK NER $\\rho$ drops by 0.022, while RE $\\rho$ increases by 0.091, likely reflecting reduced diversity at lower temperature interacting differently across tasks.\nLP exhibits the largest temperature effect on NER ($\\rho{=}0.249$ at $T{=}0.7$ vs.\\ $0.205$ at $T{=}1.0$, $\\Delta{=}{+}0.044$), consistent with lower temperature concentrating probability mass and improving LP's discriminative power for quality estimation; RE $T{=}0.7$ LP data is not available.\nAcross all comparisons, the signal hierarchy is preserved at both temperatures on NER (SJ${>}$FK${>}$LP at $T{=}0.7$: $0.364{>}0.289{>}0.249$; at $T{=}1.0$: $0.360{>}0.267{>}0.205$).\n\n\\paragraph{Sample size scaling.}\nIncreasing from $N{=}8$ to $N{=}16$ improves SJ on Qwen SciERC NER: $\\rho$ rises from 0.360 to $0.411{\\pm}0.010$ (three seeds: 0.398, 0.423, 0.410), a gain of $+0.047$.\nThe magnitude of $N$-scaling gains is setting-dependent (LLaMA SciERC NER yields $+0.016$ and Qwen CoNLL NER $+0.014$), though the direction is consistently positive.\nLLaMA CoNLL exhibits the most uniform scaling: all four consistency signals gain $\\Delta\\rho{\\approx}{+}0.042$ (range: $+0.039$ to $+0.044$) while LP gains only $+0.004$ (Table~\\ref{tab:quality_estimation}).\nFK $N$-scaling is seed-dependent: Qwen SciERC gains range from $+0.005$ to $+0.023$ across seeds (mean $+0.016$), while LLaMA CoNLL yields $+0.039$ (3-seed mean); individual seed FK shifts vary substantially under the unified pipeline, so this should not be interpreted as a robust trend.\nVC $N$-scaling is consistently positive ($+0.005$ on Qwen CoNLL, $+0.018$ on LLaMA SciERC, $+0.030$ on Qwen SciERC), while LP is approximately $N$-invariant ($\\Delta{\\leq}0.034$).\nSJ, EM, and VC scale consistently across all tested settings; only FK shows seed-dependent variation that does not constitute a reliable trend, structural and binary-agreement signals are the most robust to $N$.\nAt $N{=}16$, SJ converges to comparable NER performance with VC ($\\Delta{=}0.002$) while exhibiting lower cross-seed variance ($\\sigma{=}0.010$ vs.\\ $0.026$), a more stable alternative at higher sample sizes.\n\n\\paragraph{Transfer across model families.}\nLLaMA-3.1-8B-Instruct shows a similar SJ--FK ordering on SciERC NER (SJ $\\rho{=}0.325{\\pm}0.021$, FK $\\rho{=}0.256{\\pm}0.024$, $\\Delta\\rho{=}0.069$; permutation $p{=}0.06$, borderline).\nOn CoNLL, the gap across model families is minimal (Table~\\ref{tab:quality_estimation}): SJ achieves $\\rho{=}0.431$ (LLaMA) vs.\\ 0.436 (Qwen), $\\Delta{=}0.005$.\nAt $N{=}16$, the structural-over-LP advantage holds across all four tested NER settings: Qwen SciERC (VC $\\rho{=}0.409$ vs.\\ LP 0.239, $\\Delta{=}{+}0.170$), Qwen CoNLL (EM $\\rho{=}0.463$ vs.\\ LP 0.328, $\\Delta{=}{+}0.135$),\\footnote{Qwen CoNLL $N{=}16$ was not recomputed under the unified pipeline; LP $\\rho{=}0.328$ may differ slightly from the registry value (0.315) due to instance filtering.} LLaMA SciERC (VC $\\rho{=}0.452$ vs.\\ LP 0.277, $\\Delta{=}{+}0.175$), and LLaMA CoNLL 3-seed (SJ $\\rho{=}0.474{\\pm}0.009$ vs.\\ LP $0.311{\\pm}0.003$, $\\Delta{=}{+}0.163$).\n\n\\paragraph{FK independence: instance-level permutation test.}\\label{app:fk_independence}\n\nTo verify that Fleiss' $\\kappa$ reflects genuine within-instance agreement rather than marginal-rate artifacts, we conduct instance-level permutation tests across three configurations.\nFor each instance, we permute sample labels 10{,}000 times to generate a null distribution of FK under independence, then compare the observed FK against this null via a one-sample $t$-test and permutation $p$-value.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Instance-level FK independence test. Permutation tests confirm FK reflects true within-instance agreement (all $p{<}0.001$). Split-half reliability $r$ computed by randomly partitioning $N$ samples into two halves and correlating their FK scores.}\n\\label{tab:fk_independence}\n\\begin{tabular}{lrcccc}\n\\toprule\nConfig & $n$ & FK mean & 95\\% CI & $t$ & Split-half $r$ \\\\\n\\midrule\nSciERC (Qwen) & 529 & 0.402 & [0.376, 0.428] & 30.8 & 0.395 \\\\\nCoNLL (LLaMA) & 2{,}756 & 0.927 & [0.919, 0.935] & 225.9 & 0.578 \\\\\nCoNLL (Qwen) & 2{,}756 & 0.720 & [0.706, 0.734] & 102.1 & 0.520 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTable~\\ref{tab:fk_independence} reports the results.\nAll configurations reject the independence null at $p{<}0.001$ ($n{=}529$--$2{,}756$), FK captures genuine inter-sample agreement rather than chance label co-occurrence.\nSplit-half reliability ranges from $r{=}0.395$ (SciERC) to $r{=}0.578$ (CoNLL LLaMA), moderate stability: FK estimates from half the samples correlate positively with those from the other half, though the SciERC value suggests noisier estimation on harder tasks with fewer samples.\nThe higher FK means on CoNLL ($0.720$--$0.927$) vs.\\ SciERC ($0.402$) mirror the difficulty gradient observed in the main quality estimation results.\n\n\\section{Calibration Analysis}\\label{app:calibration}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_reliability}\n\\caption{Reliability diagrams on SciERC ($N{=}8$, $T{=}1.0$). Top: mean F1 vs.\\ binned confidence; bottom: instance counts per bin. Left: NER; right: RE. NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE shows greater miscalibration (ECE 0.109--0.339), RE calibration remains challenging for compound extraction tasks.}\n\\label{fig:reliability}\n\\end{figure*}\n\nReliability diagrams use 10 equal-width bins.\nNER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE exhibits greater miscalibration (ECE 0.109--0.339), translating consistency scores into calibrated confidence estimates is feasible for NER but remains challenging for compound extraction tasks.\n\n\\section{Additional Analyses}\\label{app:additional}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_signal_heatmap}\n\\caption{Quality estimation heatmap (Spearman $\\rho$) across five signals and four configurations. Left: full evaluation set; right: conditional set (non-zero F1 instances). On the full set, structural signals dominate on SciERC NER while all signals converge on CoNLL. On the conditional set, EM emerges as the strongest signal on both NER ($\\rho{=}0.360$) and RE ($\\rho{=}0.417$), while LP RE collapses to near-zero ($\\rho{=}0.011$).}\n\\label{fig:signal_heatmap}\n\\end{figure*}\n\n\\paragraph{Per-relation diagnostic.}\nRE signal degradation is relation-specific.\n\\textsc{Feature-Of} has near-zero correlation ($\\rho{=}0.004$), while \\textsc{Hyponym-Of} achieves $\\rho{=}0.646$.\nThe primary bottleneck is entity span errors, which account for 55.5\\% of RE false negatives. This is a prerequisite failure that consistency signals cannot detect, as they measure agreement among equally incorrect extractions.\nWe note that RE analysis relies on a single dataset (SciERC); generalization to other RE benchmarks remains to be validated.\n\n\\paragraph{Capability stratification.}\nFor NER, SJ effectiveness scales with structural complexity: on SciERC instances with 6+ entities, $\\rho{=}0.547$, compared to $\\rho{=}0.415$ for 1--2 entities.\nThe SJ advantage over LP remains stable across sentence-length quartiles ($\\Delta\\rho{\\approx}0.08$--$0.20$).\nFor RE, SJ $\\rho$ increases monotonically with sentence length (Q1: 0.110 $\\to$ Q4: 0.473; Fisher $z$-test $p{=}0.004$): longer, more relation-dense sentences provide richer structure for consistency-based estimation.\nBoth proxies are weakly correlated with F1 ($|r|{<}0.15$), they capture input complexity rather than directly predicting output quality; however, entity count and sentence length are themselves moderately correlated ($\\rho{=}0.650$), so they reflect overlapping rather than independent complexity dimensions.\nFor RE, entity count and relation count are strongly correlated ($\\rho{=}0.769$) and thus reflect a single structural complexity dimension rather than independent axes.\nOn the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\\rho{=}0.630$, LP $\\rho{=}0.554$, and SJ $\\rho{=}0.502$, all far above the full-set levels.\nRicher relational structure provides more signal for consistency-based estimation, complementing the task-level boundary established by WNUT-17: structural signals are most effective within a ``sweet spot'' of sufficient model capability and sufficient output complexity.\n\n\\paragraph{Length vs.\\ log-probability.}\nFigure~\\ref{fig:length_logprob_scatter} shows that mean log-probability is weakly positively correlated with output length (NER: $\\rho{=}0.386$, $n{=}4{,}232$; RE: $\\rho{=}0.326$, $n{=}3{,}176$), ruling out length-penalty confounding as an explanation for LP's selection failure: longer outputs receive \\textit{higher}, not lower, token-averaged log-probability under constrained decoding.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_length_logprob_scatter}\n\\caption{Output length vs.\\ mean log-probability on SciERC ($N{=}8$, $T{=}1.0$). Positive correlations (NER: $\\rho{=}0.386$; RE: $\\rho{=}0.326$) rule out length-penalty confounding.}\n\\label{fig:length_logprob_scatter}\n\\end{figure}\n\n\\paragraph{Evaluation circularity and LOO-SJ equivalence.}\nConsensus-proximity selection chooses $\\hat{y} = \\arg\\max_{y_i} \\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$.\nLeave-one-out SJ (LOO-SJ) for sample $y_i$ is $\\text{LOO-SJ}_i = \\frac{1}{N-1}\\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$.\nSince the $\\frac{1}{N-1}$ constant is shared across all candidates within an instance, $\\arg\\max_{y_i} \\text{LOO-SJ}_i = \\arg\\max_{y_i} \\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$; the two selection rules are equivalent.\nStandard (non-LOO) SJ adds the self-comparison term $\\text{SJ}(y_i, y_i) = 1$ to each candidate, which is constant and thus does not affect ranking.\nEmpirically, LOO-SJ yields $\\Delta\\rho{=}{-}0.014$ relative to standard SJ (a correlation-level difference), with a maximum per-instance score difference of $3.1{\\times}10^{-4}$ (negligible at the individual prediction level).\nEvaluation circularity is negligible.\n\n\\paragraph{SJ normalizer robustness.}\nEquation~\\ref{eq:sj} uses $\\max(|g_i|, |g_j|)$ as the denominator; an alternative is the union size $|g_i \\cup g_j|$.\nTable~\\ref{tab:sj_normalizer} compares the two normalizers across all six model--dataset combinations ($N{=}8$, $T{=}1.0$, seed${=}42$): $|\\Delta\\rho|{<}0.01$ in every case, the choice between max and union normalization does not affect conclusions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{SJ normalizer comparison (Spearman $\\rho$; $N{=}8$, $T{=}1.0$, seed${=}42$). Max: $\\max(|g_i|,|g_j|)$; Union: $|g_i \\cup g_j|$.}\n\\label{tab:sj_normalizer}\n\\begin{tabular}{@{}ll ccc@{}}\n\\toprule\nDataset & Model & $\\rho$(max) & $\\rho$(union) & $\\Delta\\rho$ \\\\\n\\midrule\nCoNLL & Qwen3-8B & .436 & .438 & $-$.002 \\\\\nCoNLL & Qwen3-4B & .422 & .421 & $+$.000 \\\\\nCoNLL & LLaMA-8B & .431 & .432 & $-$.000 \\\\\nSciERC & Qwen3-8B & .360 & .365 & $-$.005 \\\\\nSciERC & Qwen3-4B & .422 & .423 & $-$.001 \\\\\nSciERC & LLaMA-8B & .363 & .372 & $-$.009 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Conditional filtering details.}\nOn LLaMA conditional RE (non-zero F1 instances), SJ recovers to $\\rho{=}0.405$ while FK drops to $\\rho{=}0.259$, consistent with the NER structural advantage; on full-set RE, however, the SJ--FK difference is non-significant ($\\Delta\\rho{=}{-}0.005$, $p{=}0.53$; preliminary).\nAt $N{=}16$, the divergence persists: SJ maintains $\\rho{=}0.308$ on conditional RE while LP drops to $\\rho{=}{-}0.026$.\nEM ranks first across all four tested conditional configurations: SciERC NER ($\\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\\rho{=}0.466$), CoNLL LLaMA 3-seed ($\\rho{=}0.462$), and SciERC RE ($\\rho{=}0.417$). This holds despite full-set rankings ranging from \\#1 (CoNLL Qwen) to \\#5 (SciERC RE).\nOn the full set, EM is diluted by trivial agreement: instances where all $N$ samples produce identical (possibly incorrect) outputs receive EM${=}1$ regardless of quality, compressing the signal's dynamic range.\nOn the conditional set, where the model demonstrably produces varied outputs, exact agreement becomes the strongest quality signal.\nThe margin over SJ is largest on RE ($\\Delta\\rho{=}{+}0.171$), where compound extraction decisions amplify output variability, and smallest on CoNLL LLaMA ($\\Delta\\rho{=}{+}0.002$), where all signals converge near $\\rho{\\approx}0.46$.\n\n\\paragraph{WNUT-17 full signal analysis.}\nTable~\\ref{tab:wnut} reports all five signals on WNUT-17 with full-set and conditional $\\rho$.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Quality estimation on WNUT-17 (Qwen, $N{=}16$, $T{=}1.0$, $n{=}689$). Cond: non-zero F1 instances ($n{=}334$). Full-set $\\rho$ reflects binary success prediction; conditional $\\rho$ measures quality gradation. LP's conditional $\\rho$ is highest despite negative full-set $\\rho$.}\n\\label{tab:wnut}\n\\begin{tabular}{lcccc}\n\\toprule\nSignal & $\\rho$ & AUROC & Cond.\\ $\\rho$ & Cond.\\ $p$ \\\\\n\\midrule\nVC      & .724 & .913 & .038 & .487 \\\\\nFK      & .125 & .555 & .169 & .002 \\\\\nSJ      & .089 & .517 & .288 & ${<}$1e-7 \\\\\nEM      & .050 & .487 & .333 & ${<}$1e-9 \\\\\nLP & $-$.410 & .219 & .350 & ${<}$1e-10 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\nThe full-set $p$-values are: VC ${<}$1e-112, FK $p{=}0.001$, SJ $p{=}0.020$, EM $p{=}0.194$, LP ${<}$1e-28.\nVC's high full-set $\\rho{=}0.724$ is entirely driven by the zero/non-zero boundary (conditional $\\rho{=}0.038$, $p{=}0.49$), while LP's conditional $\\rho{=}0.350$ is the highest among all signals on the non-zero subset, full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.\n\n\\paragraph{Cross-configuration selection analysis.}\nTable~\\ref{tab:cross_selection} extends the selection analysis to four additional configurations.\nOn LLaMA SciERC, where output diversity remains substantial (18\\% identical outputs, 39\\% unique), LP achieves the highest selection F1 (0.652) at $N{=}8$ but still falls within bootstrap noise of single-sample (0.646), replicating the gap observed on Qwen SciERC (Table~\\ref{tab:selection}).\nOn CoNLL, 57--88\\% of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect (single-sample F1 ${\\approx}$0.91--0.92) rather than signal failure, and selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{Best-of-$N$ selection F1 (macro, instance-averaged) across configurations ($T{=}1.0$). Best non-oracle signal per row in \\textbf{bold}. At $N{=}8$, no signal significantly outperforms greedy in any configuration. At $N{=}16$ on LLaMA CoNLL, VC achieves small but significant gains ($+0.28$~pp, $p{<}0.03$; see text below). CoNLL shows especially tight clustering where greedy already exceeds 0.90.}\n\\label{tab:cross_selection}\n\\begin{tabular}{llccccccc}\n\\toprule\nConfig & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\\\\n\\midrule\nLLaMA/SciERC $N{=}8$ & 529 & .646 & .778 & .643 & .639 & .634 & \\textbf{.652} & .633 \\\\\nLLaMA/SciERC $N{=}16$ & 529 & .645 & .806 & \\textbf{.649} & \\textbf{.649} & .640 & .646 & .640 \\\\\nQwen/CoNLL $N{=}8$ & 2{,}756 & .908 & .948 & \\textbf{.899} & .893 & .898 & .897 & .895 \\\\\nLLaMA/CoNLL $N{=}8$ & 2{,}756 & .924 & .943 & .924 & \\textbf{.925} & .924 & .924 & .923 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\paragraph{Diminishing returns of $N$-scaling.}\nOur $N{=}8$ and $N{=}16$ comparisons (Table~\\ref{tab:robustness}) characterize the marginal value of additional samples for test-time scaling \\cite{brown2024monkeys, snell2025scaling}.\nFor quality estimation, structural signals benefit consistently but sublinearly: SJ $\\rho$ improves by $+0.047$ (Qwen SciERC, 3-seed mean) and $+0.032$ (LLaMA CoNLL, 3-seed mean) when doubling from $N{=}8$ to $N{=}16$, while log-probability is approximately $N$-invariant ($\\Delta\\rho{\\leq}0.021$).\nStructural signals use $\\binom{N}{2}$ pairwise comparisons (28 pairs at $N{=}8$, 120 at $N{=}16$), but the $\\rho$ improvement is far less than proportional, each additional comparison yields diminishing information.\nThis asymmetry gives structural signals a relative advantage in the compute-constrained regime: at $N{=}8$, SJ already achieves $\\rho{=}0.431$ on LLaMA CoNLL (vs.\\ LP $\\rho{=}0.307$, $\\Delta{=}{+}0.124$), and the gap \\textit{widens} at $N{=}16$ ($\\Delta{=}{+}0.163$) because structural signals continue to benefit from additional pairwise evidence while LP does not.\nFor sample selection, additional samples increase the oracle upper bound (more draws raise the probability of a high-quality candidate), but signal-based selection remains flat because the selector's inability to identify the best candidate is a granularity limitation, not a sample size limitation.\nThe practical implication is that $N{=}8$ captures most of the achievable quality estimation benefit; further scaling widens rather than closes the correlation-selection gap absent stronger per-sample selectors.\n\n\\paragraph{$N{=}16$ CoNLL selection: small but significant.}\nWhile quality estimation benefits sublinearly from $N$-scaling, selection behavior at $N{=}16$ reveals a nuanced exception on LLaMA CoNLL.\nVC achieves the largest gain over single-sample ($+0.28$~pp, $p{=}0.003$--$0.027$ across 3 seeds, all significant), with SJ, FK, and EM at $+0.22$--$0.23$~pp and LP at $+0.12$~pp (2/3 seeds significant).\nThese gains are statistically significant but practically minimal: oracle headroom at $N{=}16$ is only 2.5~pp, so VC captures approximately 10\\% of the available headroom.\nThis reinforces the primary finding: even under the most favorable conditions (high baseline performance, more candidates, and aggregated multi-seed evidence), signal-based selection recovers only a fraction of the oracle headroom available.\n\n\\section{Bootstrap CI for Signal Comparisons}\\label{app:bootstrap_signal}\n\nTable~\\ref{tab:bootstrap_signal_ci} reports bootstrap confidence intervals for individual signal $\\rho$ and pairwise $\\Delta\\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$).\nThe SJ--LP gap ($\\Delta\\rho{=}{+}0.155$) is clearly significant, the structural advantage reported in \\S\\ref{sec:qe_results} is robust.\nThe VC--SJ gap ($\\Delta\\rho{=}{+}0.019$) is not significant; these two structural signals perform comparably.\nThe SJ--EM gap ($\\Delta\\rho{=}{+}0.065$) is borderline significant, with the CI lower bound at $+0.003$ and upper bound at $+0.130$.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Bootstrap 95\\% CIs for signal $\\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$). Top: individual signals. Bottom: pairwise $\\Delta\\rho$; ``Sig.'' indicates whether the 95\\% CI excludes zero.}\n\\label{tab:bootstrap_signal_ci}\n\\begin{tabular}{lcc}\n\\toprule\nSignal & $\\rho$ & 95\\% CI \\\\\n\\midrule\nVC & +0.379 & [+0.299, +0.456] \\\\\nSJ & +0.360 & [+0.277, +0.437] \\\\\nEM & +0.295 & [+0.212, +0.371] \\\\\nFK & +0.267 & [+0.176, +0.354] \\\\\nLP & +0.205 & [+0.119, +0.291] \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{0.5em}\n\n\\begin{tabular}{lccc}\n\\toprule\nComparison & $\\Delta\\rho$ & 95\\% CI & Sig. \\\\\n\\midrule\nSJ $-$ LP & +0.155 & [+0.074, +0.234] & Yes \\\\\nVC $-$ SJ & +0.019 & [$-$0.033, +0.073] & No \\\\\nSJ $-$ EM & +0.065 & [+0.003, +0.130] & Marginal$^\\dagger$ \\\\\n\\bottomrule\n\\end{tabular}\n\n\\smallskip\n{\\footnotesize $^\\dagger$Marginally significant without multiple comparison correction; would not survive Bonferroni correction for 10 pairwise comparisons ($\\alpha_{\\text{adj}}{=}0.005$).}\n\\end{table}\n\nAt $N{=}16$ ($B{=}10{,}000$, permutation test), the structural advantage extends to FK comparisons.\nOn SciERC NER ($n{=}529$), SJ--FK ($\\Delta\\rho{=}0.147$--$0.160$, all $p{\\leq}0.002$) and VC--FK ($\\Delta\\rho{=}0.138$--$0.188$, all $p{\\leq}0.003$) are clearly significant across all three seeds; EM--FK is seed-dependent ($\\Delta\\rho{=}0.054$--$0.093$, $p{=}0.048$--$0.15$).\nOn CoNLL ($n{=}2{,}756$), all signals significantly outperform FK: EM $\\Delta\\rho{=}0.071$ ($p{<}0.001$), SJ $\\Delta\\rho{=}0.056$ ($p{<}0.001$), VC $\\Delta\\rho{=}0.022$ ($p{=}0.040$).\n\n\\section{Diversity and Selection Analysis}\\label{app:diversity}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_selection_gap}\n\\caption{The correlation-selection gap on SciERC NER ($N{=}8$, $T{=}1.0$, 2-seed mean). Bars show best-of-$N$ selection F1; the line marks quality estimation $\\rho$. Despite $\\rho$ up to 0.40, no signal significantly outperforms single-sample (all $p{>}0.05$; Table~\\ref{tab:selection}). Dashed line indicates oracle upper bound. RE selection results in Table~\\ref{tab:selection}.}\n\\label{fig:selection_gap}\n\\end{figure*}\n\n\\paragraph{Output diversity quantification.}\nTable~\\ref{tab:diversity} summarizes output diversity across configurations.\nOn SciERC, output diversity is substantial: Qwen produces 43\\% unique outputs per instance (mean 3.5 distinct out of $N{=}8$), with per-sample F1 standard deviation of 0.144 and mean pairwise SJ of 0.703.\nLLaMA shows similar diversity (39\\% unique, F1 std 0.11).\nOn CoNLL, diversity collapses: 57\\% (Qwen) to 88\\% (LLaMA) of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect where single-sample F1 already exceeds 0.90.\nWNUT-17 shows 55\\% identical outputs, driven by the 52\\% zero-F1 rate.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Output diversity across configurations ($N{=}8$, $T{=}1.0$). ``Identical'' = fraction of instances with all $N$ outputs identical. ``Unique'' = mean fraction of distinct outputs per instance.}\n\\label{tab:diversity}\n\\begin{tabular}{lcc}\n\\toprule\nConfig & Identical & Unique \\\\\n\\midrule\nQwen/SciERC & 11\\% & 43\\% \\\\\nLLaMA/SciERC & 18\\% & 39\\% \\\\\nQwen/CoNLL & 57\\% & --- \\\\\nLLaMA/CoNLL & 88\\% & --- \\\\\nWNUT-17 & 55\\% & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Oracle-improvable fraction.}\nAcross SciERC configurations, 39--42\\% of instances contain at least one sample with F1 exceeding single-sample\\footnote{Oracle-improvable and diversity-stratified analyses use $n{=}529$ (excluding instances with empty gold annotations; see \\S\\ref{sec:evaluation}); the diversity quantification in Table~\\ref{tab:diversity} uses the full test set.}: Qwen NER 42.0\\% (222/529, mean headroom $+$31.9~pp among improvable instances), Qwen RE 41.3\\% (164/397, $+$45.3~pp), LLaMA NER 39.3\\% (208/529, $+$33.7~pp).\nOn CoNLL, only 4--9\\% of instances are improvable, consistent with the ceiling effect.\n\n\\paragraph{Diversity-stratified selection gap.}\nOn the 44\\% of Qwen SciERC instances with high diversity (${\\geq}4$ unique outputs among 8 samples, $n{=}232$), oracle headroom reaches $+$16.3~pp, yet all consistency-based signals (SJ, FK, EM, VC) select at or below single-sample, and LP, the only per-sample signal, achieves merely $+$0.8~pp.\nLLaMA replicates this pattern: on its high-diversity subset ($n{=}186$), oracle headroom reaches $+$20.1~pp while consistency signals remain at or below single-sample and LP captures only $+$2.0~pp.\nThis rules out insufficient diversity as an explanation for the correlation-selection gap.\n\n\\paragraph{Instance degeneracy statistics.}\nTable~\\ref{tab:degeneracy} quantifies instance degeneracy across configurations. ``Constant F1'' denotes instances where all $N$ samples receive identical instance-level F1; ``Constant utility'' denotes instances where MBR (SJ) utility is identical across candidates, preventing ranking.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Instance degeneracy statistics ($T{=}1.0$). ``Constant F1'': all $N$ samples receive identical instance-level F1. ``Constant utility'': MBR (SJ) utility identical across candidates. 4B data confirms degeneracy scales with model capability.}\n\\label{tab:degeneracy}\n\\begin{tabular}{lccc}\n\\toprule\n& \\shortstack{SciERC 8B\\\\($N{=}8$)} & \\shortstack{SciERC 4B\\\\($N{=}8$)} & \\shortstack{CoNLL 8B\\\\($N{=}16$)} \\\\\n\\midrule\nConstant F1 & 17.8\\% & 10.4\\% & 48.3\\% \\\\\nConstant utility & 13\\% & 7.0\\% & 49\\% \\\\\nOracle gap closed (non-deg.) & 23\\% & 25.2\\% & 41\\% \\\\\nWithin-inst.\\ SJ $\\rho$ (median) & 0.524 & 0.550 & 0.994 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{TOST equivalence testing.}\\label{app:tost}\nThe primary evidence against selection gains comes from effect sizes and confidence intervals: Cohen's $d{=}0.038$ for the best signal (NER LP) and bootstrap 95\\% CI [$-$3.0, $+$4.2]~pp spanning zero.\nTable~\\ref{tab:tost} supplements this with two one-sided tests (TOST), testing whether each signal's selection F1 is equivalent to single-sample within a bound $\\delta$.\nThe $\\delta$ values are contextualized against oracle headroom (12--18~pp): $\\delta{=}5$~pp corresponds to forgoing 28--38\\% of the available headroom, $\\delta{=}3$~pp forgoing 17--23\\%, and $\\delta{=}2$~pp less than 15\\%.\nThese proportions use the same test data that defines the headroom, introducing circularity: $\\delta$ is anchored to the very quantity it contextualizes.\nWe address this below with externally anchored equivalence margins.\nThe breakpoint $\\delta^*$, the minimum equivalence margin at which each signal passes TOST, ranges from approximately 1.3~pp (SJ, ${\\sim}$10\\% of oracle headroom) to 3.4~pp (FK, ${\\sim}$26\\%) on NER, and from approximately 2.9~pp (LP, ${\\sim}$16\\%) to 6.5~pp (VC, ${\\sim}$36\\%) on RE.\nOn NER ($n{=}529$), at $\\delta{=}{\\pm}2$~pp, SJ and LP are confirmed equivalent to single-sample (TOST $p{<}0.05$); at $\\delta{=}{\\pm}3$~pp, four of five signals pass; at $\\delta{=}{\\pm}5$~pp, all five pass.\nOn RE ($n{=}397$, preliminary), EM and VC fail equivalence even at $\\delta{=}{\\pm}5$~pp due to systematic underperformance ($\\Delta{=}{-}3.2$~pp and $-4.5$~pp respectively).\nThe effect sizes are negligible ($d{=}0.038$) and confidence intervals span zero, with TOST confirming equivalence at practically meaningful margins.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{TOST equivalence testing: signals vs.\\ single-sample on SciERC ($N{=}8$, $T{=}1.0$). \\checkmark: equivalent at $p{<}0.05$; \\texttimes: not equivalent. $\\Delta$: mean F1 difference (signal $-$ single-sample).}\n\\label{tab:tost}\n\\begin{tabular}{l cccc cccc}\n\\toprule\n& \\multicolumn{4}{c}{\\textbf{NER}} & \\multicolumn{4}{c}{\\textbf{RE}} \\\\\n\\cmidrule(lr){2-5} \\cmidrule(lr){6-9}\nSignal & $\\Delta$ & $\\pm$2 & $\\pm$3 & $\\pm$5 & $\\Delta$ & $\\pm$2 & $\\pm$3 & $\\pm$5 \\\\\n\\midrule\nLP & +0.6 & \\checkmark & \\checkmark & \\checkmark & $-$0.9 & \\texttimes & \\checkmark & \\checkmark \\\\\nSJ & +0.1 & \\checkmark & \\checkmark & \\checkmark & $-$1.8 & \\texttimes & \\texttimes & \\checkmark \\\\\nFK & $-$0.5 & \\texttimes & \\checkmark & \\checkmark & $-$1.6 & \\texttimes & \\texttimes & \\checkmark \\\\\nEM & $-$0.8 & \\texttimes & \\checkmark & \\checkmark & $-$3.2 & \\texttimes & \\texttimes & \\texttimes \\\\\nVC & $-$1.0 & \\texttimes & \\texttimes & \\checkmark & $-$4.5 & \\texttimes & \\texttimes & \\texttimes \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{External equivalence margins.}\nThe oracle-headroom anchors above introduce circularity, as a reviewer correctly noted: $\\delta$ is calibrated against the very quantity it contextualizes.\nTo resolve this, we supplement with three externally grounded margins:\n(1) $\\delta_{\\mathrm{SEM}}$: the bootstrapped standard error of single-sample F1 (0.43--1.33~pp depending on configuration), which represents measurement noise;\n(2) $\\delta_{\\mathrm{practical}}{=}0.5$~pp, the threshold below which NER differences are considered negligible \\cite{ratinov2009design};\n(3) $\\delta_{\\mathrm{literature}}{=}1.0$~pp, the approximate significant-difference threshold established in NER evaluation methodology \\cite{bergkirkpatrick2012empirical}.\n\nResults under these external anchors diverge sharply by configuration.\nOn LLaMA CoNLL ($n{=}2{,}756$), all signals pass equivalence at every $\\delta$ ($p{<}0.001$), consistent with the near-zero selection deltas ($|\\Delta|{\\leq}0.1$~pp) and tight CIs at this sample size.\nOn Qwen CoNLL ($n{=}2{,}756$), no signal passes at any external $\\delta$: selection F1 degrades by 0.9--1.5~pp relative to single-sample, which exceeds even $\\delta_{\\mathrm{literature}}$.\nOn SciERC NER ($n{=}529$), only SJ passes at $\\delta_{\\mathrm{SEM}}{=}1.33$~pp (the widest SEM bound); all other signals and tighter margins fail.\nThese external anchors confirm that the equivalence conclusion is configuration-dependent: LLaMA CoNLL selection is robustly equivalent to single-sample under any reasonable margin, while SciERC and Qwen CoNLL selection shows detectable degradation at externally calibrated thresholds.\n\n\\paragraph{Multiple comparison considerations.}\\label{app:multiple_comparisons}\nOur primary selection analysis involves ${\\sim}$20 comparisons (5 signals $\\times$ 3--4 configurations).\nSince all primary selection results are non-significant ($p{>}0.05$), applying Benjamini-Hochberg correction can only make these results more conservative, strengthening the ``no signal beats greedy'' conclusion.\nThe sole positive finding, the non-tied LP subset ($+2.9$~pp, $p{=}0.004$; \\S\\ref{sec:discussion}), survives Bonferroni correction over 5 signal comparisons ($p_{\\mathrm{adj}}{=}0.020 < 0.05$), as noted in the main text footnote.\nFor quality estimation signal rankings, differences between the top signals (e.g., VC vs.\\ SJ on SciERC) should be interpreted as descriptive rather than as statistically confirmed orderings, given the limited power of 3-seed comparisons.\n\n\\section{Multi-Seed Stability}\\label{app:multiseed}\n\nTable~\\ref{tab:multiseed} reports quality estimation metrics across three random seeds for both model families on SciERC ($N{=}8$, $T{=}1.0$).\nOn NER, the signal ranking VC${>}$SJ${>}$EM${>}$FK${>}$LP is identical across all six model-seed combinations, with $\\sigma{\\leq}0.025$ for all signals (rankings are stable across our 3 seeds, though statistical power with $n{=}3$ is limited).\nOn RE (Qwen only, preliminary), VC remains the top signal ($\\rho{=}0.309{\\pm}0.024$), but LP rises to \\#2 ($\\rho{=}0.297{\\pm}0.022$), above FK, SJ, and EM. This reversal from the NER ranking reflects RE's higher sensitivity to per-sample scoring.\nLLaMA absolute values are systematically lower than Qwen on NER, consistent with the directionally-consistent-but-magnitude-dependent characterization in the main text.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Multi-seed quality estimation on SciERC ($N{=}8$, $T{=}1.0$, seeds: 42, 123, 456). NER: both models; RE: Qwen only (preliminary). Signal ranking is stable across seeds ($\\sigma{\\leq}0.025$). $\\sigma$ is population standard deviation over 3 seeds.}\n\\label{tab:multiseed}\n\\begin{tabular}{lccccc}\n\\toprule\n& LP & FK & SJ & VC & EM \\\\\n\\midrule\n\\multicolumn{6}{l}{\\textit{NER Spearman $\\rho$ (mean $\\pm\\sigma$)}} \\\\\nQwen & .217${\\pm}$.013 & .254${\\pm}$.016 & .364${\\pm}$.018 & .386${\\pm}$.019 & .307${\\pm}$.008 \\\\\nLLaMA & .162${\\pm}$.025 & .256${\\pm}$.024 & .325${\\pm}$.021 & .384${\\pm}$.014 & .279${\\pm}$.011 \\\\\n\\midrule\n\\multicolumn{6}{l}{\\textit{RE Spearman $\\rho$ (mean $\\pm\\sigma$, Qwen)}} \\\\\nQwen & .297${\\pm}$.022 & .290${\\pm}$.012 & .249${\\pm}$.002 & .309${\\pm}$.024 & .135${\\pm}$.016 \\\\\n\\midrule\n\\multicolumn{6}{l}{\\textit{NER AUROC (mean $\\pm\\sigma$)}} \\\\\nQwen & .579${\\pm}$.008 & .600${\\pm}$.016 & .659${\\pm}$.016 & .677${\\pm}$.011 & .631${\\pm}$.013 \\\\\nLLaMA & .565${\\pm}$.008 & .593${\\pm}$.006 & .632${\\pm}$.012 & .673${\\pm}$.009 & .606${\\pm}$.005 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Training Configuration}\\label{app:training}\n\nBoth models are fine-tuned with identical hyperparameters (Table~\\ref{tab:training}) to ensure comparisons across model families reflect model differences rather than training confounds.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Training configuration. Both Qwen3-8B and LLaMA-3.1-8B-Instruct use identical settings unless noted.}\n\\label{tab:training}\n\\begin{tabular}{ll}\n\\toprule\nParameter & Value \\\\\n\\midrule\nLoRA rank / $\\alpha$ & 32 / 64 \\\\\nLoRA target & All linear modules \\\\\nLoRA dropout & 0 \\\\\nOptimizer & AdamW \\\\\nLearning rate & 2e-4, cosine schedule \\\\\nWarmup ratio & 0.1 \\\\\nEffective batch size & 16 (2 $\\times$ grad.\\ accum.\\ 8) \\\\\nEpochs & 5 \\\\\nMax sequence length & 2048 \\\\\nPrecision & bf16 \\\\\nGradient checkpointing & Enabled \\\\\nMax gradient norm & 1.0 \\\\\nTraining seed & 42 \\\\\nFramework & LLaMA Factory \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Dataset-specific}} \\\\\nSciERC split & 1861 / 275 / 551 \\\\\nCoNLL / WNUT & +\\,load\\_best\\_model\\_at\\_end, \\\\\n& eval\\_steps${=}$200, save\\_limit${=}$5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Prompt template.}\nFor NER, we use a structured prompt:\n\\begin{quote}\n\\small\n\\texttt{System:} You are an expert in Named Entity Recognition.\\\\\n\\texttt{User:} Extract all named entities from the following text. Output as JSON.\\\\\nText: \\texttt{\\{input\\_text\\}}\\\\\nEntity types: \\texttt{\\{schema\\_types\\}}\n\\end{quote}\nRE follows the same structure with ``Relation Extraction'' and relation type lists substituted accordingly.\n\n\\paragraph{Constrained decoding.}\nInference uses vLLM with XGrammar-based JSON schema enforcement \\cite{willard2023guided}, which constrains outputs to valid entity/relation structures matching the target schema.\nThis eliminates format errors but may compress per-sample diversity by restricting the output space.\\footnote{SciERC training used \\texttt{enable\\_thinking=True} (LLaMA Factory 0.9.4 default), injecting empty \\texttt{&lt;think>&lt;/think>} blocks (4--5 tokens) into each training response with loss computation; CoNLL and WNUT explicitly set \\texttt{enable\\_thinking=False}. Constrained decoding at inference time enforces JSON-only output, suppressing thinking tokens. See \\S\\ref{sec:setup} and Limitations for discussion of this confound.}",
      "numLines": 500,
      "startLine": 1,
      "totalLines": 1354
    }
  }
}
```

</details>

---

### Tool call

_source line 33_

<details open><summary>🔧 Tool call — Grep · `toolu_01K4TWghswBXF2eDdnC8WuZo`</summary>

```json
{
  "pattern": "0\\.614",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "071b2f10-bb20-4a57-a4f1-ff7b98ed1873",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MN9CfjJJuXLHcqxMJrhzsF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 618,
      "cache_creation_input_tokens": 15363,
      "cache_read_input_tokens": 26892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15363
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

_source line 34 · 2026-05-18T05:45:48.402Z_

<details><summary>↩ Tool result · `toolu_01K4TWghswBXF2eDdnC8WuZo`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "f1b02ab7-9ce0-4a6f-a34f-ead8818bb5c0",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 35_

<details open><summary>🔧 Tool call — Grep · `toolu_01H2RQVhydsUHVq9U4Qj45NL`</summary>

```json
{
  "pattern": "0\\.752",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "1dfbcd66-656a-4333-9f67-b4ab4a4e9d62",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MN9CfjJJuXLHcqxMJrhzsF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 618,
      "cache_creation_input_tokens": 15363,
      "cache_read_input_tokens": 26892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15363
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

_source line 36 · 2026-05-18T05:45:49.313Z_

<details><summary>↩ Tool result · `toolu_01H2RQVhydsUHVq9U4Qj45NL`</summary>

```text
docs/paper/sections/appendix.tex:1057:0.8 & 27.2 & 0.031 & 0.471 & 0.752 \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "73799de7-e599-447d-8351-bf5405c819e4",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/appendix.tex:1057:0.8 & 27.2 & 0.031 & 0.471 & 0.752 \\\\",
    "numLines": 1
  }
}
```

</details>

---

### Tool call

_source line 37_

<details open><summary>🔧 Tool call — Grep · `toolu_01JFGekVubWXqZQavk4cmJcH`</summary>

```json
{
  "pattern": "13\\.8",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "05609574-091b-4657-b4e4-b6976da0809f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MN9CfjJJuXLHcqxMJrhzsF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 618,
      "cache_creation_input_tokens": 15363,
      "cache_read_input_tokens": 26892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15363
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

_source line 38 · 2026-05-18T05:45:50.259Z_

<details><summary>↩ Tool result · `toolu_01JFGekVubWXqZQavk4cmJcH`</summary>

```text
docs/paper/sections/experiments.tex:109:Few-NERD & 32{,}565 & .748 & 12.4\,pp & 13.8\% & .421 & $\mathbf{+1.36}$\,pp \\
docs/paper/sections/experiments.tex:117:Under standard early stopping, Few-NERD degeneracy is 13.8\% (training convergence modulates this rate, Appendix~\ref{app:epoch_confound}), and LP achieves $+1.36$~pp (95\% CI $[+1.18, +1.53]$, $p{<}0.001$), while all structural signals degrade selection (VC $-1.79$, SJ $-2.14$~pp).
docs/paper/sections/experiments.tex:120:The cross-dataset gradient is consistent with an inverse relationship (59.1\% $\to$ $-1.05$~pp, 17.8\% $\to$ $+0.61$~pp, 13.8\% $\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory given 5+ confounds; Figure~\ref{fig:degeneracy_scatter}), with supporting evidence from per-entity-type analysis within Few-NERD ($n{=}8$, $\rho{=}{-}0.881$, $p{=}0.004$; entity types share model, tokenizer, and temperature, so effective degrees of freedom may be lower than 6).
docs/paper/sections/experiments.tex:122:Few-NERD satisfies both conditions: low degeneracy (13.8\%) and strong alignment ($\rho{\approx}0.5$; per-type detail in Appendix~\ref{app:per_type_lp}).
docs/paper/sections/discussion.tex:29:Even at degeneracy approaching Few-NERD levels (12.5\% vs.\ 13.8\%), LP does not improve selection because alignment remains weak ($\rho{=}0.225$ vs.\ Few-NERD ${\sim}$0.5).
docs/paper/sections/appendix.tex:1044:However, even at $T{=}1.2$ where degeneracy (12.5\%) approaches Few-NERD levels (13.8\%), within-instance $\rho(\text{LP}, \text{F1})$ remains at 0.225, far below Few-NERD's ${\sim}$0.5.
docs/paper/sections/appendix.tex:1171:Instance degeneracy is 13.8\% (vs.\ 17.8\% on SciERC, 59.1\% on CoNLL).
docs/paper/sections/appendix.tex:1197:(4)~Low degeneracy (13.8\%) combined with strong LP-quality alignment ($\rho{\approx}0.5$) enables LP selection: candidates differ in F1 more often, and LP can rank them effectively. This contrasts with SciERC (17.8\% degeneracy but weak alignment $\rho{\approx}0.24$, LP $+0.61$~pp) and CoNLL (59.1\%, LP $-1.05$~pp).
docs/paper/sections/appendix.tex:1262:The cross-dataset degeneracy gradient (59.1\% $\to$ 17.8\% $\to$ 13.8\%) is inversely associated with LP selection effectiveness at the macro level ($n{=}3$ datasets; exploratory).\footnote{Partial Spearman correlation controlling for entity-type frequency yields $\rho{=}{-}0.47$ (vs.\ raw $\rho{=}{-}0.38$); type frequency does not confound the degeneracy--LP relationship.}
docs/paper/sections/introduction.tex:13:For selection, LP achieves $+1.36$~pp on Few-NERD ($p{<}0.001$) when two conditions are jointly met: low instance degeneracy (13.8\%) and adequate alignment ($\rho{\approx}0.5$), with gains scaling with $N$ ($+0.52$~pp, $p{=}0.003$).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "dc48d363-a2ea-42a4-8d2f-dfa79ce44d0f",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:109:Few-NERD & 32{,}565 & .748 & 12.4\\,pp & 13.8\\% & .421 & $\\mathbf{+1.36}$\\,pp \\\\\ndocs/paper/sections/experiments.tex:117:Under standard early stopping, Few-NERD degeneracy is 13.8\\% (training convergence modulates this rate, Appendix~\\ref{app:epoch_confound}), and LP achieves $+1.36$~pp (95\\% CI $[+1.18, +1.53]$, $p{<}0.001$), while all structural signals degrade selection (VC $-1.79$, SJ $-2.14$~pp).\ndocs/paper/sections/experiments.tex:120:The cross-dataset gradient is consistent with an inverse relationship (59.1\\% $\\to$ $-1.05$~pp, 17.8\\% $\\to$ $+0.61$~pp, 13.8\\% $\\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory given 5+ confounds; Figure~\\ref{fig:degeneracy_scatter}), with supporting evidence from per-entity-type analysis within Few-NERD ($n{=}8$, $\\rho{=}{-}0.881$, $p{=}0.004$; entity types share model, tokenizer, and temperature, so effective degrees of freedom may be lower than 6).\ndocs/paper/sections/experiments.tex:122:Few-NERD satisfies both conditions: low degeneracy (13.8\\%) and strong alignment ($\\rho{\\approx}0.5$; per-type detail in Appendix~\\ref{app:per_type_lp}).\ndocs/paper/sections/discussion.tex:29:Even at degeneracy approaching Few-NERD levels (12.5\\% vs.\\ 13.8\\%), LP does not improve selection because alignment remains weak ($\\rho{=}0.225$ vs.\\ Few-NERD ${\\sim}$0.5).\ndocs/paper/sections/appendix.tex:1044:However, even at $T{=}1.2$ where degeneracy (12.5\\%) approaches Few-NERD levels (13.8\\%), within-instance $\\rho(\\text{LP}, \\text{F1})$ remains at 0.225, far below Few-NERD's ${\\sim}$0.5.\ndocs/paper/sections/appendix.tex:1171:Instance degeneracy is 13.8\\% (vs.\\ 17.8\\% on SciERC, 59.1\\% on CoNLL).\ndocs/paper/sections/appendix.tex:1197:(4)~Low degeneracy (13.8\\%) combined with strong LP-quality alignment ($\\rho{\\approx}0.5$) enables LP selection: candidates differ in F1 more often, and LP can rank them effectively. This contrasts with SciERC (17.8\\% degeneracy but weak alignment $\\rho{\\approx}0.24$, LP $+0.61$~pp) and CoNLL (59.1\\%, LP $-1.05$~pp).\ndocs/paper/sections/appendix.tex:1262:The cross-dataset degeneracy gradient (59.1\\% $\\to$ 17.8\\% $\\to$ 13.8\\%) is inversely associated with LP selection effectiveness at the macro level ($n{=}3$ datasets; exploratory).\\footnote{Partial Spearman correlation controlling for entity-type frequency yields $\\rho{=}{-}0.47$ (vs.\\ raw $\\rho{=}{-}0.38$); type frequency does not confound the degeneracy--LP relationship.}\ndocs/paper/sections/introduction.tex:13:For selection, LP achieves $+1.36$~pp on Few-NERD ($p{<}0.001$) when two conditions are jointly met: low instance degeneracy (13.8\\%) and adequate alignment ($\\rho{\\approx}0.5$), with gains scaling with $N$ ($+0.52$~pp, $p{=}0.003$).",
    "numLines": 10
  }
}
```

</details>

---

### Tool call

_source line 39_

<details open><summary>🔧 Tool call — Grep · `toolu_01DNuasez5BCfbN7M6ks9yuU`</summary>

```json
{
  "pattern": "0\\.205",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "0437b18e-4756-4daa-accd-a27a9672707b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MN9CfjJJuXLHcqxMJrhzsF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 618,
      "cache_creation_input_tokens": 15363,
      "cache_read_input_tokens": 26892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15363
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

_source line 40 · 2026-05-18T05:45:50.712Z_

<details><summary>↩ Tool result · `toolu_01DNuasez5BCfbN7M6ks9yuU`</summary>

```text
docs/paper/sections/experiments.tex:48:On SciERC (medium difficulty), structural signals lead (VC $\rho{=}0.379$, SJ $0.360$) over LP ($0.205$); bootstrap CIs confirm the gap ($\Delta\rho{=}{+}0.155$; Appendix~\ref{app:bootstrap_signal}).
docs/paper/sections/appendix.tex:49:\quad LP & $T{=}1.0$ & 0.205 & 0.266 \\
docs/paper/sections/appendix.tex:77:LP exhibits the largest temperature effect on NER ($\rho{=}0.249$ at $T{=}0.7$ vs.\ $0.205$ at $T{=}1.0$, $\Delta{=}{+}0.044$), consistent with lower temperature concentrating probability mass and improving LP's discriminative power for quality estimation; RE $T{=}0.7$ LP data is not available.
docs/paper/sections/appendix.tex:78:Across all comparisons, the signal hierarchy is preserved at both temperatures on NER (SJ${>}$FK${>}$LP at $T{=}0.7$: $0.364{>}0.289{>}0.249$; at $T{=}1.0$: $0.360{>}0.267{>}0.205$).
docs/paper/sections/appendix.tex:284:LP & +0.205 & [+0.119, +0.291] \\
docs/paper/sections/appendix.tex:828:LP & 0.205 & 0.213 & $+$0.008 & 0.266 & 0.304 & $+$0.038 \\
docs/paper/sections/appendix.tex:1027:1.0 & $+$13.3 & 0.360 & 0.205 & ${\approx}$0.39 & ${\approx}$0.612 \\
docs/paper/sections/appendix.tex:1118:$\rho$ & 0.297 & 0.205 & 0.337 & 0.316 \\
docs/paper/sections/appendix.tex:1134:VerbConf achieves higher $\rho$ than LP on both datasets (SciERC: 0.297 vs.\ 0.205; CoNLL: 0.337 vs.\ 0.316) and competitive AUROC (SciERC: 0.681 vs.\ 0.578; CoNLL: 0.747 vs.\ 0.753), yet yields the worst selection among all signals ($\Delta{=}{-}2.45$~pp on SciERC, $-1.93$~pp on CoNLL).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "0b53b63a-aa6e-4e1c-ae79-9a918d9d3d74",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:48:On SciERC (medium difficulty), structural signals lead (VC $\\rho{=}0.379$, SJ $0.360$) over LP ($0.205$); bootstrap CIs confirm the gap ($\\Delta\\rho{=}{+}0.155$; Appendix~\\ref{app:bootstrap_signal}).\ndocs/paper/sections/appendix.tex:49:\\quad LP & $T{=}1.0$ & 0.205 & 0.266 \\\\\ndocs/paper/sections/appendix.tex:77:LP exhibits the largest temperature effect on NER ($\\rho{=}0.249$ at $T{=}0.7$ vs.\\ $0.205$ at $T{=}1.0$, $\\Delta{=}{+}0.044$), consistent with lower temperature concentrating probability mass and improving LP's discriminative power for quality estimation; RE $T{=}0.7$ LP data is not available.\ndocs/paper/sections/appendix.tex:78:Across all comparisons, the signal hierarchy is preserved at both temperatures on NER (SJ${>}$FK${>}$LP at $T{=}0.7$: $0.364{>}0.289{>}0.249$; at $T{=}1.0$: $0.360{>}0.267{>}0.205$).\ndocs/paper/sections/appendix.tex:284:LP & +0.205 & [+0.119, +0.291] \\\\\ndocs/paper/sections/appendix.tex:828:LP & 0.205 & 0.213 & $+$0.008 & 0.266 & 0.304 & $+$0.038 \\\\\ndocs/paper/sections/appendix.tex:1027:1.0 & $+$13.3 & 0.360 & 0.205 & ${\\approx}$0.39 & ${\\approx}$0.612 \\\\\ndocs/paper/sections/appendix.tex:1118:$\\rho$ & 0.297 & 0.205 & 0.337 & 0.316 \\\\\ndocs/paper/sections/appendix.tex:1134:VerbConf achieves higher $\\rho$ than LP on both datasets (SciERC: 0.297 vs.\\ 0.205; CoNLL: 0.337 vs.\\ 0.316) and competitive AUROC (SciERC: 0.681 vs.\\ 0.578; CoNLL: 0.747 vs.\\ 0.753), yet yields the worst selection among all signals ($\\Delta{=}{-}2.45$~pp on SciERC, $-1.93$~pp on CoNLL).",
    "numLines": 9
  }
}
```

</details>

---

### Tool call

_source line 41_

<details open><summary>🔧 Tool call — Grep · `toolu_018xRMMV6fWutwCSXavEsHXi`</summary>

```json
{
  "pattern": "47\\.4",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "d4efe063-db8a-4fc0-ae73-0100a1495c77",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MN9CfjJJuXLHcqxMJrhzsF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 618,
      "cache_creation_input_tokens": 15363,
      "cache_read_input_tokens": 26892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15363
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

_source line 42 · 2026-05-18T05:45:51.683Z_

<details><summary>↩ Tool result · `toolu_018xRMMV6fWutwCSXavEsHXi`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "991ab09a-905b-4163-b35c-bcfabcd45d9b",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 43_

<details open><summary>🔧 Tool call — Grep · `toolu_016BiaPxFts4tjMwkhg2m95a`</summary>

```json
{
  "pattern": "89\\.2",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "88c20fb5-d8ca-410a-aa4c-b5eb5523d4a6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MN9CfjJJuXLHcqxMJrhzsF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 618,
      "cache_creation_input_tokens": 15363,
      "cache_read_input_tokens": 26892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15363
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

_source line 44 · 2026-05-18T05:45:52.638Z_

<details><summary>↩ Tool result · `toolu_016BiaPxFts4tjMwkhg2m95a`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "9f39177c-84e6-46c9-91ef-4860f0c89b6f",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 45_

<details open><summary>🔧 Tool call — Grep · `toolu_018mJfxkz3Tg89BoCkXBRuRE`</summary>

```json
{
  "pattern": "\\-0\\.07",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "d90a9076-eea8-4495-bc85-083bf6451321",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MN9CfjJJuXLHcqxMJrhzsF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 618,
      "cache_creation_input_tokens": 15363,
      "cache_read_input_tokens": 26892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15363
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

_source line 46 · 2026-05-18T05:45:53.578Z_

<details><summary>↩ Tool result · `toolu_018mJfxkz3Tg89BoCkXBRuRE`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "cee2a660-e0a1-40d4-9f75-e7ffd5c90533",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 47_

<details open><summary>🔧 Tool call — Grep · `toolu_017ZxhN5n8NTyFfMJCAWYfKp`</summary>

```json
{
  "pattern": "0\\.42\\b",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "836b251a-a136-474f-a0e0-a78a4f07bd36",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MN9CfjJJuXLHcqxMJrhzsF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 618,
      "cache_creation_input_tokens": 15363,
      "cache_read_input_tokens": 26892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15363
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

_source line 48 · 2026-05-18T05:45:54.397Z_

<details><summary>↩ Tool result · `toolu_017ZxhN5n8NTyFfMJCAWYfKp`</summary>

```text
docs/paper/sections/experiments.tex:123:All five signals achieve positive QE on Few-NERD (LP $\rho{=}0.42$, VC $0.39$), yet only LP translates QE into selection; the gap confirms that strong instance-level QE cannot rank candidates within an instance.
docs/paper/sections/conclusion.tex:4:All signals achieve reliable quality estimation ($\rho$ up to 0.42, AUROC up to 0.82), supporting selective prediction.
docs/paper/sections/discussion.tex:4:All signals achieve positive quality estimation across non-collapsed datasets (LP $\rho{=}0.42$ on Few-NERD, VC $\rho{=}0.38$ on SciERC, EM AUROC${=}0.82$ on CoNLL), with rankings stable across model families and a 4B ablation (Table~\ref{tab:scale_ablation}).
docs/paper/sections/discussion.tex:23:LP failures show cross-seed stability (Jaccard${=}0.42$; Appendix~\ref{app:lp_failure_stability}), consistent with a systematic failure mode.
docs/paper/sections/abstract.tex:4:All signals achieve reliable quality estimation ($\rho$ up to 0.42, AUROC up to 0.82), supporting selective prediction.
docs/paper/sections/appendix.tex:862:LP selection failures (instances where LP-selected F1 $<$ single-sample F1) show moderate cross-seed stability: the average pairwise Jaccard similarity is 0.42 (range: 0.38--0.46); failures are partially systematic (driven by instance complexity) but not fully deterministic.
docs/paper/sections/appendix.tex:1194:(1)~All five signals achieve positive QE ($\rho$ 0.29--0.42); quality estimation works on Few-NERD. LP leads ($\rho{=}0.42$), followed by VC ($0.39$); the ranking differs from SciERC where VC leads, consistent with dataset-specific signal informativeness.
docs/paper/sections/introduction.tex:12:All signals achieve reliable quality estimation ($\rho$ up to 0.42, AUROC up to 0.82; Figure~\ref{fig:overview}), supporting selective prediction.
docs/paper/sections/introduction.tex:20:\caption{The correlation-selection gap. \textbf{Left}: consistency signals reliably predict instance-level quality ($\rho$ up to 0.45 on CoNLL, 0.38 on the primary test bed, 0.42 on Few-NERD; AUROC up to 0.82). \textbf{Right}: quality estimation does not translate to selection; all methods approximately match greedy decoding ($T{=}0$) despite 13~pp oracle headroom (\S\ref{sec:discussion}).}
docs/paper/sections/introduction.tex:30:    Five signals from three families evaluated on four NER benchmarks, two model families, and a 4B ablation, achieving reliable quality estimation ($\rho$ up to 0.42; AUROC up to 0.82).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "43be2a65-fb57-47d7-b0d2-4d5a034d732f",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:123:All five signals achieve positive QE on Few-NERD (LP $\\rho{=}0.42$, VC $0.39$), yet only LP translates QE into selection; the gap confirms that strong instance-level QE cannot rank candidates within an instance.\ndocs/paper/sections/conclusion.tex:4:All signals achieve reliable quality estimation ($\\rho$ up to 0.42, AUROC up to 0.82), supporting selective prediction.\ndocs/paper/sections/discussion.tex:4:All signals achieve positive quality estimation across non-collapsed datasets (LP $\\rho{=}0.42$ on Few-NERD, VC $\\rho{=}0.38$ on SciERC, EM AUROC${=}0.82$ on CoNLL), with rankings stable across model families and a 4B ablation (Table~\\ref{tab:scale_ablation}).\ndocs/paper/sections/discussion.tex:23:LP failures show cross-seed stability (Jaccard${=}0.42$; Appendix~\\ref{app:lp_failure_stability}), consistent with a systematic failure mode.\ndocs/paper/sections/abstract.tex:4:All signals achieve reliable quality estimation ($\\rho$ up to 0.42, AUROC up to 0.82), supporting selective prediction.\ndocs/paper/sections/appendix.tex:862:LP selection failures (instances where LP-selected F1 $<$ single-sample F1) show moderate cross-seed stability: the average pairwise Jaccard similarity is 0.42 (range: 0.38--0.46); failures are partially systematic (driven by instance complexity) but not fully deterministic.\ndocs/paper/sections/appendix.tex:1194:(1)~All five signals achieve positive QE ($\\rho$ 0.29--0.42); quality estimation works on Few-NERD. LP leads ($\\rho{=}0.42$), followed by VC ($0.39$); the ranking differs from SciERC where VC leads, consistent with dataset-specific signal informativeness.\ndocs/paper/sections/introduction.tex:12:All signals achieve reliable quality estimation ($\\rho$ up to 0.42, AUROC up to 0.82; Figure~\\ref{fig:overview}), supporting selective prediction.\ndocs/paper/sections/introduction.tex:20:\\caption{The correlation-selection gap. \\textbf{Left}: consistency signals reliably predict instance-level quality ($\\rho$ up to 0.45 on CoNLL, 0.38 on the primary test bed, 0.42 on Few-NERD; AUROC up to 0.82). \\textbf{Right}: quality estimation does not translate to selection; all methods approximately match greedy decoding ($T{=}0$) despite 13~pp oracle headroom (\\S\\ref{sec:discussion}).}\ndocs/paper/sections/introduction.tex:30:    Five signals from three families evaluated on four NER benchmarks, two model families, and a 4B ablation, achieving reliable quality estimation ($\\rho$ up to 0.42; AUROC up to 0.82).",
    "numLines": 10
  }
}
```

</details>

---

### Assistant

_source line 49_

<details><summary>Logged reasoning block</summary>

```text
Now let me continue reading the appendix and search for additional values. Let me check:

1. 0.614 → No matches found. ✅ Old value removed.
2. 0.752 → Found in appendix.tex:1057 - need to check context.
3. 13.8 → All instances refer to Few-NERD degeneracy (13.8%), which is the correct value.
4. 0.205 → Multiple instances. This is the SciERC LP ρ. Need to check: was 0.205 updated or is it the correct value?


5. Looking at the task more carefully, I see that 0.215 is the updated value for SciERC LP ρ in tab:fewnerd, which uses the max-LP evaluation protocol, while 0.205 appears in tab:quality_estimation with a different evaluation setup. The task specifies that 0.215 is the unified new value for tab:fewnerd. I'm confirming that 0.215 is indeed the correct value in tab:fewnerd, while 0.205 in tab:quality_estimation uses a different LP aggregation method, so both are valid for their respective contexts. Now I need to track down where that 0.752 value appears in the appendix—it might be from a different experiment like a temperature ablation—and I've verified that 47.4 and 89.2 don't show up anywhere else.

Let me systematically go through the abstract claims to make sure everything checks out: the ρ up to 0.42 aligns with what's in tab:quality_estimation for Few-NERD, and the AUROC up to 0.82 is close to the 0.816 value I'm seeing for CoNLL with Qwen, though I should verify exactly where that 0.82 figure comes from in the experiments. So the AUROC value of 0.816 rounds to 0.82, which matches the figure caption claim. For the ρ metrics, I'm seeing 0.421 on Few-NERD rounds to 0.42, and on CoNLL the value is 0.451 which would round to 0.45 as stated in the caption. These are all consistent with standard academic rounding practices.

But there's a discrepancy I'm noticing: the abstract claims "ρ up to 0.42" as the maximum, yet the quality estimation table shows CoNLL Qwen EM achieves 0.451, which is actually higher. This suggests the abstract is understating the true maximum ρ value, unless there's a specific subset or condition where 0.42 represents the actual peak. There's a discrepancy here—the figure caption shows ρ reaching 0.45 on CoNLL, but the abstract claims "ρ up to 0.42," which doesn't match the overall maximum of 0.451. This could be intentional if the abstract is specifically highlighting the LP signal's performance on Few-NERD rather than the global maximum, but it's worth flagging as a potential inconsistency in how the results are being reported.

Now let me check what that 0.752 value in the appendix refers to.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "8131fecc-35b5-4d6d-a259-fa5f95a105a6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W6BiTovGjroo8RGXgack9C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19170,
      "cache_read_input_tokens": 42255,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19170
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

继续读取 appendix 中 0.752 附近的上下文，并搜索更多关键值。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "64864e53-b7f6-4e8c-99ed-594781eb4cd1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W6BiTovGjroo8RGXgack9C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19170,
      "cache_read_input_tokens": 42255,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19170
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

<details open><summary>🔧 Tool call — Read · `toolu_011bCHhpN9WWqCfU46N8S2yG`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "offset": 1040,
  "limit": 80
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "9f280b3f-4f9d-47c5-b9ba-b911e8105919",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W6BiTovGjroo8RGXgack9C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19170,
      "cache_read_input_tokens": 42255,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19170
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

_source line 52 · 2026-05-18T05:46:39.060Z_

<details><summary>↩ Tool result · `toolu_011bCHhpN9WWqCfU46N8S2yG`</summary>

```text
1040	\paragraph{Temperature controls degeneracy and LP spread.}
1041	Table~\ref{tab:t_degeneracy} reports instance degeneracy (constant F1, gold-filtered) and median within-instance LP range across four temperatures on SciERC.
1042	Both quantities are strictly monotonic in $T$: degeneracy falls from 40.3\% ($T{=}0.5$) to 12.5\% ($T{=}1.2$), while LP range increases from 0.015 to 0.058 nats.
1043	Temperature thus provides a direct lever for practitioners to shift the degeneracy regime.
1044	However, even at $T{=}1.2$ where degeneracy (12.5\%) approaches Few-NERD levels (13.8\%), within-instance $\rho(\text{LP}, \text{F1})$ remains at 0.225, far below Few-NERD's ${\sim}$0.5.
1045	This confirms that temperature controls degeneracy (the first necessary condition) but cannot improve LP-quality alignment (the second condition), which is largely determined by task structure and remains relatively stable across generation configurations (\S\ref{app:epoch_confound}); the two conditions are jointly necessary and independently variable.
1046	
1047	\begin{table}[h]
1048	\centering
1049	\small
1050	\caption{Temperature sensitivity of degeneracy and LP spread (SciERC NER, Qwen3-8B, $N{=}8$). Degeneracy: constant-F1, gold-filtered. LP range: median within-instance range.}
1051	\label{tab:t_degeneracy}
1052	\begin{tabular}{ccccc}
1053	\toprule
1054	$T$ & Degen.\% & LP range (nats) & Fleiss' $\kappa$ & SJ mean \\
1055	\midrule
1056	0.5 & 40.3 & 0.015 & 0.572 & 0.830 \\
1057	0.8 & 27.2 & 0.031 & 0.471 & 0.752 \\
1058	1.0 & 17.8 & 0.042 & 0.405 & 0.700 \\
1059	1.2 & 12.5 & 0.058 & 0.352 & 0.647 \\
1060	\bottomrule
1061	\end{tabular}
1062	\end{table}
1063	
1064	\section{Cross-Dataset OOD Analysis}\label{app:ood}
1065	
1066	To test whether confidence signals generalize under domain shift, we evaluate models on out-of-distribution data: a SciERC-trained model applied to CoNLL instances (wider$\to$narrower schema) and vice versa (Table~\ref{tab:ood}).
1067	
1068	\begin{table}[t]
1069	\centering
1070	\small
1071	\caption{Cross-dataset OOD quality estimation (Spearman $\rho$, Qwen3-8B, $N{=}8$, $T{=}1.0$, seed${=}42$). SciERC$\to$CoNLL: SciERC-trained model on CoNLL instances ($n{=}2756$). CoNLL$\to$SciERC: CoNLL-trained model on SciERC instances ($n{=}529$, excluded from conclusions due to catastrophic model failure). In-domain $\rho$ from Table~\ref{tab:quality_estimation} (same model, same seed). \textsuperscript{***}$p{<}0.001$, \textsuperscript{*}$p{<}0.05$.}
1072	\label{tab:ood}
1073	\begin{tabular}{l ccc ccc}
1074	\toprule
1075	 & \multicolumn{3}{c}{\textbf{SciERC$\to$CoNLL}} & \multicolumn{3}{c}{\textbf{CoNLL$\to$SciERC}} \\
1076	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
1077	Signal & $\rho$ & In-dom. & $\Delta$ & $\rho$ & In-dom. & $\Delta$ \\
1078	\midrule
1079	VC & .469\textsuperscript{***} & .379 & +.090 & +.105\textsuperscript{*} & .379 & $-$.274 \\
1080	SJ & .378\textsuperscript{***} & .360 & +.018 & $-$.186\textsuperscript{***} & .360 & $-$.546 \\
1081	EM & .300\textsuperscript{***} & .295 & +.005 & $-$.202\textsuperscript{***} & .295 & $-$.497 \\
1082	FK & .285\textsuperscript{***} & .267 & +.018 & $-$.070 & .267 & $-$.337 \\
1083	LP & .246\textsuperscript{***} & .205 & +.041 & $-$.152\textsuperscript{***} & .205 & $-$.357 \\
1084	\bottomrule
1085	\end{tabular}
1086	\end{table}
1087	
1088	\paragraph{Wider-to-narrower schema transfer.}
1089	When the SciERC-trained model (6 NER types) is applied to CoNLL (4 types), all signals remain significant ($p{<}0.001$) and structural signals improve over their in-domain levels (same model, seed${=}42$, $N{=}8$; in-domain $\rho$ from Table~\ref{tab:quality_estimation}): VC reaches $\rho{=}0.469$ (in-domain $0.379$, $\Delta{=}{+}0.090$), SJ $\rho{=}0.378$ (in-domain $0.360$, $\Delta{=}{+}0.018$), and FK $\rho{=}0.285$ (in-domain $0.267$, $\Delta{=}{+}0.018$).
1090	The wider training schema subsumes CoNLL's narrower schema, so the model produces reasonable outputs even out-of-domain (single-sample F1${=}0.522$), and structural signals benefit from the simpler target schema's reduced output ambiguity.
1091	
1092	\paragraph{Narrower-to-wider schema transfer (excluded).}
1093	The reverse direction is excluded from our conclusions due to catastrophic model failure, not signal failure.
1094	The CoNLL-trained model recognizes only 4 news entity types (PER, ORG, LOC, MISC) and has no relation extraction capability; when applied to SciERC's 6 scientific entity types and 7 relation types, the model cannot produce meaningful structured outputs (single-sample NER F1${=}0.009$, RE F1${=}0.001$).
1095	Under this regime, most signals flip to negative or near-zero correlations (Table~\ref{tab:ood}); only VC retains weak positive correlation ($\rho{=}0.105$, $p{=}0.016$).
1096	These negative correlations reflect the model systematically generating confident but incorrect outputs, a capability failure analogous to WNUT-17 (\S\ref{sec:qe_results}) and not evidence against signal utility.
1097	
1098	\paragraph{Asymmetry interpretation.}
1099	The directional asymmetry is driven by schema coverage: wider$\to$narrower preserves signal utility because the SciERC model's 6-type schema subsumes CoNLL's 4 types, while narrower$\to$wider fails because the CoNLL model lacks the entity and relation types required by SciERC.
1100	This extends the capability boundary identified on WNUT-17 to the domain-shift setting: confidence signals require sufficient model capability as a prerequisite, and results from the CoNLL$\to$SciERC direction should not be interpreted as evidence of signal degradation under domain shift.
1101	
1102	\section{Verbalized Confidence}\label{app:verbalized_confidence}
1103	
1104	We evaluate verbalized confidence (VerbConf) as a second per-sample signal following \citet{tian2023calibration}: after generating each structured output, the model is prompted to rate its confidence on a 1--10 scale.
1105	Table~\ref{tab:verbconf} reports quality estimation and selection results.
1106	
1107	\begin{table}[t]
1108	\centering
1109	\small
1110	\caption{Verbalized confidence (VerbConf) vs.\ log-probability selection (Qwen3-8B, $N{=}8$, $T{=}1.0$, seed${=}42$). Parse fail: fraction of samples where the confidence score could not be extracted.}
1111	\label{tab:verbconf}
1112	\begin{tabular}{l cc cc}
1113	\toprule
1114	 & \multicolumn{2}{c}{\textbf{SciERC NER}} & \multicolumn{2}{c}{\textbf{CoNLL NER}} \\
1115	\cmidrule(lr){2-3} \cmidrule(lr){4-5}
1116	Metric & VerbConf & LP & VerbConf & LP \\
1117	\midrule
1118	$\rho$ & 0.297 & 0.205 & 0.337 & 0.316 \\
1119	AUROC & 0.681 & 0.578 & 0.747 & 0.753 \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "dcfdfd44-edb6-40da-848e-a737b864e02b",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "\\paragraph{Temperature controls degeneracy and LP spread.}\nTable~\\ref{tab:t_degeneracy} reports instance degeneracy (constant F1, gold-filtered) and median within-instance LP range across four temperatures on SciERC.\nBoth quantities are strictly monotonic in $T$: degeneracy falls from 40.3\\% ($T{=}0.5$) to 12.5\\% ($T{=}1.2$), while LP range increases from 0.015 to 0.058 nats.\nTemperature thus provides a direct lever for practitioners to shift the degeneracy regime.\nHowever, even at $T{=}1.2$ where degeneracy (12.5\\%) approaches Few-NERD levels (13.8\\%), within-instance $\\rho(\\text{LP}, \\text{F1})$ remains at 0.225, far below Few-NERD's ${\\sim}$0.5.\nThis confirms that temperature controls degeneracy (the first necessary condition) but cannot improve LP-quality alignment (the second condition), which is largely determined by task structure and remains relatively stable across generation configurations (\\S\\ref{app:epoch_confound}); the two conditions are jointly necessary and independently variable.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Temperature sensitivity of degeneracy and LP spread (SciERC NER, Qwen3-8B, $N{=}8$). Degeneracy: constant-F1, gold-filtered. LP range: median within-instance range.}\n\\label{tab:t_degeneracy}\n\\begin{tabular}{ccccc}\n\\toprule\n$T$ & Degen.\\% & LP range (nats) & Fleiss' $\\kappa$ & SJ mean \\\\\n\\midrule\n0.5 & 40.3 & 0.015 & 0.572 & 0.830 \\\\\n0.8 & 27.2 & 0.031 & 0.471 & 0.752 \\\\\n1.0 & 17.8 & 0.042 & 0.405 & 0.700 \\\\\n1.2 & 12.5 & 0.058 & 0.352 & 0.647 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Cross-Dataset OOD Analysis}\\label{app:ood}\n\nTo test whether confidence signals generalize under domain shift, we evaluate models on out-of-distribution data: a SciERC-trained model applied to CoNLL instances (wider$\\to$narrower schema) and vice versa (Table~\\ref{tab:ood}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-dataset OOD quality estimation (Spearman $\\rho$, Qwen3-8B, $N{=}8$, $T{=}1.0$, seed${=}42$). SciERC$\\to$CoNLL: SciERC-trained model on CoNLL instances ($n{=}2756$). CoNLL$\\to$SciERC: CoNLL-trained model on SciERC instances ($n{=}529$, excluded from conclusions due to catastrophic model failure). In-domain $\\rho$ from Table~\\ref{tab:quality_estimation} (same model, same seed). \\textsuperscript{***}$p{<}0.001$, \\textsuperscript{*}$p{<}0.05$.}\n\\label{tab:ood}\n\\begin{tabular}{l ccc ccc}\n\\toprule\n & \\multicolumn{3}{c}{\\textbf{SciERC$\\to$CoNLL}} & \\multicolumn{3}{c}{\\textbf{CoNLL$\\to$SciERC}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\nSignal & $\\rho$ & In-dom. & $\\Delta$ & $\\rho$ & In-dom. & $\\Delta$ \\\\\n\\midrule\nVC & .469\\textsuperscript{***} & .379 & +.090 & +.105\\textsuperscript{*} & .379 & $-$.274 \\\\\nSJ & .378\\textsuperscript{***} & .360 & +.018 & $-$.186\\textsuperscript{***} & .360 & $-$.546 \\\\\nEM & .300\\textsuperscript{***} & .295 & +.005 & $-$.202\\textsuperscript{***} & .295 & $-$.497 \\\\\nFK & .285\\textsuperscript{***} & .267 & +.018 & $-$.070 & .267 & $-$.337 \\\\\nLP & .246\\textsuperscript{***} & .205 & +.041 & $-$.152\\textsuperscript{***} & .205 & $-$.357 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Wider-to-narrower schema transfer.}\nWhen the SciERC-trained model (6 NER types) is applied to CoNLL (4 types), all signals remain significant ($p{<}0.001$) and structural signals improve over their in-domain levels (same model, seed${=}42$, $N{=}8$; in-domain $\\rho$ from Table~\\ref{tab:quality_estimation}): VC reaches $\\rho{=}0.469$ (in-domain $0.379$, $\\Delta{=}{+}0.090$), SJ $\\rho{=}0.378$ (in-domain $0.360$, $\\Delta{=}{+}0.018$), and FK $\\rho{=}0.285$ (in-domain $0.267$, $\\Delta{=}{+}0.018$).\nThe wider training schema subsumes CoNLL's narrower schema, so the model produces reasonable outputs even out-of-domain (single-sample F1${=}0.522$), and structural signals benefit from the simpler target schema's reduced output ambiguity.\n\n\\paragraph{Narrower-to-wider schema transfer (excluded).}\nThe reverse direction is excluded from our conclusions due to catastrophic model failure, not signal failure.\nThe CoNLL-trained model recognizes only 4 news entity types (PER, ORG, LOC, MISC) and has no relation extraction capability; when applied to SciERC's 6 scientific entity types and 7 relation types, the model cannot produce meaningful structured outputs (single-sample NER F1${=}0.009$, RE F1${=}0.001$).\nUnder this regime, most signals flip to negative or near-zero correlations (Table~\\ref{tab:ood}); only VC retains weak positive correlation ($\\rho{=}0.105$, $p{=}0.016$).\nThese negative correlations reflect the model systematically generating confident but incorrect outputs, a capability failure analogous to WNUT-17 (\\S\\ref{sec:qe_results}) and not evidence against signal utility.\n\n\\paragraph{Asymmetry interpretation.}\nThe directional asymmetry is driven by schema coverage: wider$\\to$narrower preserves signal utility because the SciERC model's 6-type schema subsumes CoNLL's 4 types, while narrower$\\to$wider fails because the CoNLL model lacks the entity and relation types required by SciERC.\nThis extends the capability boundary identified on WNUT-17 to the domain-shift setting: confidence signals require sufficient model capability as a prerequisite, and results from the CoNLL$\\to$SciERC direction should not be interpreted as evidence of signal degradation under domain shift.\n\n\\section{Verbalized Confidence}\\label{app:verbalized_confidence}\n\nWe evaluate verbalized confidence (VerbConf) as a second per-sample signal following \\citet{tian2023calibration}: after generating each structured output, the model is prompted to rate its confidence on a 1--10 scale.\nTable~\\ref{tab:verbconf} reports quality estimation and selection results.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Verbalized confidence (VerbConf) vs.\\ log-probability selection (Qwen3-8B, $N{=}8$, $T{=}1.0$, seed${=}42$). Parse fail: fraction of samples where the confidence score could not be extracted.}\n\\label{tab:verbconf}\n\\begin{tabular}{l cc cc}\n\\toprule\n & \\multicolumn{2}{c}{\\textbf{SciERC NER}} & \\multicolumn{2}{c}{\\textbf{CoNLL NER}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nMetric & VerbConf & LP & VerbConf & LP \\\\\n\\midrule\n$\\rho$ & 0.297 & 0.205 & 0.337 & 0.316 \\\\\nAUROC & 0.681 & 0.578 & 0.747 & 0.753 \\\\",
      "numLines": 80,
      "startLine": 1040,
      "totalLines": 1354
    }
  }
}
```

</details>

---

### Tool call

_source line 53_

<details open><summary>🔧 Tool call — Grep · `toolu_017BbqKL4atairdQHzhbrZR5`</summary>

```json
{
  "pattern": "0\\.776",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "30c7a36d-91ae-45a4-8a06-966a50841195",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W6BiTovGjroo8RGXgack9C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19170,
      "cache_read_input_tokens": 42255,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19170
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

_source line 54 · 2026-05-18T05:46:40.131Z_

<details><summary>↩ Tool result · `toolu_017BbqKL4atairdQHzhbrZR5`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "e3d2d7bc-266c-4486-8fad-c1b62ae32694",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 55_

<details open><summary>🔧 Tool call — Grep · `toolu_01PskSXsC33M9Pmvc8JAJEbP`</summary>

```json
{
  "pattern": "0\\.778",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "bae2c711-b760-49b9-84d4-2962ca9e56e0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W6BiTovGjroo8RGXgack9C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19170,
      "cache_read_input_tokens": 42255,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19170
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

_source line 56 · 2026-05-18T05:46:41.062Z_

<details><summary>↩ Tool result · `toolu_01PskSXsC33M9Pmvc8JAJEbP`</summary>

```text
docs/paper/sections/experiments.tex:68:Oracle & $0.778 \pm 0.003$ & --- \\
docs/paper/sections/experiments.tex:89:On SciERC ($n{=}529$, 2-seed sign tests\footnote{Seed variation $\sigma{\leq}0.026$ (Table~\ref{tab:multiseed}); MDE${\approx}$1.5~pp at 80\% power for $n{=}529$, so a 1~pp effect yields only ${\sim}$55\% power. Few-NERD ($n{=}32{,}565$; MDE${\approx}$0.22~pp) provides the definitive test.}), the oracle (0.778) reveals 13.3~pp of headroom, but LP achieves $+0.2$~pp ($p{=}0.29$), below the MDE (${\approx}$1.5~pp).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "3ed91239-3fb1-42d0-8909-99d0f6600e8a",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:68:Oracle & $0.778 \\pm 0.003$ & --- \\\\\ndocs/paper/sections/experiments.tex:89:On SciERC ($n{=}529$, 2-seed sign tests\\footnote{Seed variation $\\sigma{\\leq}0.026$ (Table~\\ref{tab:multiseed}); MDE${\\approx}$1.5~pp at 80\\% power for $n{=}529$, so a 1~pp effect yields only ${\\sim}$55\\% power. Few-NERD ($n{=}32{,}565$; MDE${\\approx}$0.22~pp) provides the definitive test.}), the oracle (0.778) reveals 13.3~pp of headroom, but LP achieves $+0.2$~pp ($p{=}0.29$), below the MDE (${\\approx}$1.5~pp).",
    "numLines": 2
  }
}
```

</details>

---

### Tool call

_source line 57_

<details open><summary>🔧 Tool call — Grep · `toolu_01SYiteS19qskBBqtMQKcWGn`</summary>

```json
{
  "pattern": "0\\.644",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "fd6acd1e-44e0-436f-831b-520b297a545f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W6BiTovGjroo8RGXgack9C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19170,
      "cache_read_input_tokens": 42255,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19170
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

_source line 58 · 2026-05-18T05:46:41.547Z_

<details><summary>↩ Tool result · `toolu_01SYiteS19qskBBqtMQKcWGn`</summary>

```text
docs/paper/sections/experiments.tex:113:\footnotetext{SciERC values (greedy${=}0.644$, headroom${=}13.2$~pp) differ slightly from Table~\ref{tab:selection} (greedy${=}0.645$, headroom${=}13.3$~pp) due to max-LP aggregation and single-seed evaluation; the ranking is unchanged.}
docs/paper/sections/experiments.tex:173:Supervised verifiers (logistic regression, MLP, random forest) trained on all five signals (3-fold CV, SciERC, $N{=}16$, $+17.9$~pp headroom) all perform at or below greedy\footnote{Greedy F1 is 0.644 (3-seed mean), consistent with Table~\ref{tab:selection}.} (LR: $-0.3$~pp; MLP: $-0.6$~pp; RF: $-2.9$~pp).
docs/paper/sections/appendix.tex:984:\footnotetext{$N$-scaling analysis uses gold-filtered evaluation ($n{=}529$, greedy F1${=}0.640$). Values differ slightly from Table~\ref{tab:selection} (0.645) and Table~\ref{tab:fewnerd} (0.644) due to seed and aggregation differences; relative trends are consistent.}
docs/paper/sections/appendix.tex:1341:Greedy F1 & 0.650 & 0.644 & 0.649 \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "24b0f27c-9b3b-4856-8716-1e0a0399154d",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:113:\\footnotetext{SciERC values (greedy${=}0.644$, headroom${=}13.2$~pp) differ slightly from Table~\\ref{tab:selection} (greedy${=}0.645$, headroom${=}13.3$~pp) due to max-LP aggregation and single-seed evaluation; the ranking is unchanged.}\ndocs/paper/sections/experiments.tex:173:Supervised verifiers (logistic regression, MLP, random forest) trained on all five signals (3-fold CV, SciERC, $N{=}16$, $+17.9$~pp headroom) all perform at or below greedy\\footnote{Greedy F1 is 0.644 (3-seed mean), consistent with Table~\\ref{tab:selection}.} (LR: $-0.3$~pp; MLP: $-0.6$~pp; RF: $-2.9$~pp).\ndocs/paper/sections/appendix.tex:984:\\footnotetext{$N$-scaling analysis uses gold-filtered evaluation ($n{=}529$, greedy F1${=}0.640$). Values differ slightly from Table~\\ref{tab:selection} (0.645) and Table~\\ref{tab:fewnerd} (0.644) due to seed and aggregation differences; relative trends are consistent.}\ndocs/paper/sections/appendix.tex:1341:Greedy F1 & 0.650 & 0.644 & 0.649 \\\\",
    "numLines": 4
  }
}
```

</details>

---

### Tool call

_source line 59_

<details open><summary>🔧 Tool call — Grep · `toolu_01JxctE32ykQzFWzUyREYUvq`</summary>

```json
{
  "pattern": "0\\.645",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "23056c7a-6398-4bfd-8e27-dedcf3b15189",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W6BiTovGjroo8RGXgack9C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19170,
      "cache_read_input_tokens": 42255,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19170
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

_source line 60 · 2026-05-18T05:46:42.491Z_

<details><summary>↩ Tool result · `toolu_01JxctE32ykQzFWzUyREYUvq`</summary>

```text
docs/paper/sections/experiments.tex:69:Greedy ($T{=}0$) & $0.645 \pm 0.001$ & --- \\
docs/paper/sections/experiments.tex:113:\footnotetext{SciERC values (greedy${=}0.644$, headroom${=}13.2$~pp) differ slightly from Table~\ref{tab:selection} (greedy${=}0.645$, headroom${=}13.3$~pp) due to max-LP aggregation and single-seed evaluation; the ranking is unchanged.}
docs/paper/sections/appendix.tex:984:\footnotetext{$N$-scaling analysis uses gold-filtered evaluation ($n{=}529$, greedy F1${=}0.640$). Values differ slightly from Table~\ref{tab:selection} (0.645) and Table~\ref{tab:fewnerd} (0.644) due to seed and aggregation differences; relative trends are consistent.}
docs/paper/sections/appendix.tex:1130:VerbConf exhibits extreme score compression: mean confidence is 8.58/10 on SciERC (single-sample F1${=}0.645$) and 9.24/10 on CoNLL (single-sample F1${=}0.904$), with most scores concentrated in the 8--10 range.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "ac1c449d-ebc3-4633-938f-f76ee238779d",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:69:Greedy ($T{=}0$) & $0.645 \\pm 0.001$ & --- \\\\\ndocs/paper/sections/experiments.tex:113:\\footnotetext{SciERC values (greedy${=}0.644$, headroom${=}13.2$~pp) differ slightly from Table~\\ref{tab:selection} (greedy${=}0.645$, headroom${=}13.3$~pp) due to max-LP aggregation and single-seed evaluation; the ranking is unchanged.}\ndocs/paper/sections/appendix.tex:984:\\footnotetext{$N$-scaling analysis uses gold-filtered evaluation ($n{=}529$, greedy F1${=}0.640$). Values differ slightly from Table~\\ref{tab:selection} (0.645) and Table~\\ref{tab:fewnerd} (0.644) due to seed and aggregation differences; relative trends are consistent.}\ndocs/paper/sections/appendix.tex:1130:VerbConf exhibits extreme score compression: mean confidence is 8.58/10 on SciERC (single-sample F1${=}0.645$) and 9.24/10 on CoNLL (single-sample F1${=}0.904$), with most scores concentrated in the 8--10 range.",
    "numLines": 4
  }
}
```

</details>

---

### Tool call

_source line 61_

<details open><summary>🔧 Tool call — Grep · `toolu_0131rSA4M8HpZ5wU1m9MAEBQ`</summary>

```json
{
  "pattern": "59\\.1",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "c55f5caf-2c0e-4559-80ca-2b3be8aa2e9a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W6BiTovGjroo8RGXgack9C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19170,
      "cache_read_input_tokens": 42255,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19170
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

_source line 62 · 2026-05-18T05:46:43.424Z_

<details><summary>↩ Tool result · `toolu_0131rSA4M8HpZ5wU1m9MAEBQ`</summary>

```text
docs/paper/sections/experiments.tex:107:CoNLL & 2{,}756 & .908 & 4.0\,pp & 59.1\% & .302 & $-$1.05\,pp \\
docs/paper/sections/experiments.tex:120:The cross-dataset gradient is consistent with an inverse relationship (59.1\% $\to$ $-1.05$~pp, 17.8\% $\to$ $+0.61$~pp, 13.8\% $\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory given 5+ confounds; Figure~\ref{fig:degeneracy_scatter}), with supporting evidence from per-entity-type analysis within Few-NERD ($n{=}8$, $\rho{=}{-}0.881$, $p{=}0.004$; entity types share model, tokenizer, and temperature, so effective degrees of freedom may be lower than 6).
docs/paper/sections/conclusion.tex:6:When either condition is violated, LP gains fall below detectable thresholds despite 12\textendash 14~pp oracle headroom: on SciERC (17.8\% degeneracy, $\rho{\approx}0.24$), LP yields $+0.61$~pp (below the ${\approx}$1.5~pp MDE at 80\% power); on CoNLL (59.1\% degeneracy), LP degrades selection ($-1.05$~pp).
docs/paper/sections/discussion.tex:10:Within non-degenerate instances, MBR utility \cite{eikema2022sampling} correlates positively with F1 (SJ median $\rho{=}0.524$) and closes 23--41\% of the oracle gap, but 17.8\% (SciERC) to 59.1\% (CoNLL) of instances produce identical F1 across all samples, eliminating headroom entirely (Table~\ref{tab:degeneracy}).
docs/paper/sections/discussion.tex:11:Degeneracy is determined by the interplay of task structure, model architecture, and training convergence (Appendix~\ref{app:epoch_confound}); cross-model evidence (LLaMA 86.4\% vs.\ Qwen 59.1\% on CoNLL; Table~\ref{tab:cross_selection}) reinforces the pattern.
docs/paper/sections/appendix.tex:1171:Instance degeneracy is 13.8\% (vs.\ 17.8\% on SciERC, 59.1\% on CoNLL).
docs/paper/sections/appendix.tex:1197:(4)~Low degeneracy (13.8\%) combined with strong LP-quality alignment ($\rho{\approx}0.5$) enables LP selection: candidates differ in F1 more often, and LP can rank them effectively. This contrasts with SciERC (17.8\% degeneracy but weak alignment $\rho{\approx}0.24$, LP $+0.61$~pp) and CoNLL (59.1\%, LP $-1.05$~pp).
docs/paper/sections/appendix.tex:1262:The cross-dataset degeneracy gradient (59.1\% $\to$ 17.8\% $\to$ 13.8\%) is inversely associated with LP selection effectiveness at the macro level ($n{=}3$ datasets; exploratory).\footnote{Partial Spearman correlation controlling for entity-type frequency yields $\rho{=}{-}0.47$ (vs.\ raw $\rho{=}{-}0.38$); type frequency does not confound the degeneracy--LP relationship.}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "ca2d95d8-8649-46dd-85c9-160b5335bff2",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:107:CoNLL & 2{,}756 & .908 & 4.0\\,pp & 59.1\\% & .302 & $-$1.05\\,pp \\\\\ndocs/paper/sections/experiments.tex:120:The cross-dataset gradient is consistent with an inverse relationship (59.1\\% $\\to$ $-1.05$~pp, 17.8\\% $\\to$ $+0.61$~pp, 13.8\\% $\\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory given 5+ confounds; Figure~\\ref{fig:degeneracy_scatter}), with supporting evidence from per-entity-type analysis within Few-NERD ($n{=}8$, $\\rho{=}{-}0.881$, $p{=}0.004$; entity types share model, tokenizer, and temperature, so effective degrees of freedom may be lower than 6).\ndocs/paper/sections/conclusion.tex:6:When either condition is violated, LP gains fall below detectable thresholds despite 12\\textendash 14~pp oracle headroom: on SciERC (17.8\\% degeneracy, $\\rho{\\approx}0.24$), LP yields $+0.61$~pp (below the ${\\approx}$1.5~pp MDE at 80\\% power); on CoNLL (59.1\\% degeneracy), LP degrades selection ($-1.05$~pp).\ndocs/paper/sections/discussion.tex:10:Within non-degenerate instances, MBR utility \\cite{eikema2022sampling} correlates positively with F1 (SJ median $\\rho{=}0.524$) and closes 23--41\\% of the oracle gap, but 17.8\\% (SciERC) to 59.1\\% (CoNLL) of instances produce identical F1 across all samples, eliminating headroom entirely (Table~\\ref{tab:degeneracy}).\ndocs/paper/sections/discussion.tex:11:Degeneracy is determined by the interplay of task structure, model architecture, and training convergence (Appendix~\\ref{app:epoch_confound}); cross-model evidence (LLaMA 86.4\\% vs.\\ Qwen 59.1\\% on CoNLL; Table~\\ref{tab:cross_selection}) reinforces the pattern.\ndocs/paper/sections/appendix.tex:1171:Instance degeneracy is 13.8\\% (vs.\\ 17.8\\% on SciERC, 59.1\\% on CoNLL).\ndocs/paper/sections/appendix.tex:1197:(4)~Low degeneracy (13.8\\%) combined with strong LP-quality alignment ($\\rho{\\approx}0.5$) enables LP selection: candidates differ in F1 more often, and LP can rank them effectively. This contrasts with SciERC (17.8\\% degeneracy but weak alignment $\\rho{\\approx}0.24$, LP $+0.61$~pp) and CoNLL (59.1\\%, LP $-1.05$~pp).\ndocs/paper/sections/appendix.tex:1262:The cross-dataset degeneracy gradient (59.1\\% $\\to$ 17.8\\% $\\to$ 13.8\\%) is inversely associated with LP selection effectiveness at the macro level ($n{=}3$ datasets; exploratory).\\footnote{Partial Spearman correlation controlling for entity-type frequency yields $\\rho{=}{-}0.47$ (vs.\\ raw $\\rho{=}{-}0.38$); type frequency does not confound the degeneracy--LP relationship.}",
    "numLines": 8
  }
}
```

</details>

---

### Tool call

_source line 63_

<details open><summary>🔧 Tool call — Grep · `toolu_01ER36UCNhqrMxJeMqSwufgy`</summary>

```json
{
  "pattern": "86\\.4",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "a5655092-bb1e-4084-ac2b-11fbf76e005b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W6BiTovGjroo8RGXgack9C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19170,
      "cache_read_input_tokens": 42255,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19170
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

_source line 64 · 2026-05-18T05:46:44.374Z_

<details><summary>↩ Tool result · `toolu_01ER36UCNhqrMxJeMqSwufgy`</summary>

```text
docs/paper/sections/discussion.tex:11:Degeneracy is determined by the interplay of task structure, model architecture, and training convergence (Appendix~\ref{app:epoch_confound}); cross-model evidence (LLaMA 86.4\% vs.\ Qwen 59.1\% on CoNLL; Table~\ref{tab:cross_selection}) reinforces the pattern.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "17193137-c78e-49ba-a813-7780408e7cb9",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/discussion.tex:11:Degeneracy is determined by the interplay of task structure, model architecture, and training convergence (Appendix~\\ref{app:epoch_confound}); cross-model evidence (LLaMA 86.4\\% vs.\\ Qwen 59.1\\% on CoNLL; Table~\\ref{tab:cross_selection}) reinforces the pattern.",
    "numLines": 1
  }
}
```

</details>

---

### Tool call

_source line 65_

<details open><summary>🔧 Tool call — Grep · `toolu_01P7D2nGVN7z6URhwoxbA9Lx`</summary>

```json
{
  "pattern": "13\\.2",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "bea6db3e-03ad-44bd-bf43-de9d4de374ee",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W6BiTovGjroo8RGXgack9C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19170,
      "cache_read_input_tokens": 42255,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19170
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

_source line 66 · 2026-05-18T05:46:44.854Z_

<details><summary>↩ Tool result · `toolu_01P7D2nGVN7z6URhwoxbA9Lx`</summary>

```text
docs/paper/sections/experiments.tex:108:SciERC & 529 & .644 & 13.2\,pp & 17.8\% & .215 & $+$0.61\,pp \\
docs/paper/sections/experiments.tex:113:\footnotetext{SciERC values (greedy${=}0.644$, headroom${=}13.2$~pp) differ slightly from Table~\ref{tab:selection} (greedy${=}0.645$, headroom${=}13.3$~pp) due to max-LP aggregation and single-seed evaluation; the ranking is unchanged.}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "42d87ad9-d6dd-4660-bf5f-87d4a96a6fe5",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:108:SciERC & 529 & .644 & 13.2\\,pp & 17.8\\% & .215 & $+$0.61\\,pp \\\\\ndocs/paper/sections/experiments.tex:113:\\footnotetext{SciERC values (greedy${=}0.644$, headroom${=}13.2$~pp) differ slightly from Table~\\ref{tab:selection} (greedy${=}0.645$, headroom${=}13.3$~pp) due to max-LP aggregation and single-seed evaluation; the ranking is unchanged.}",
    "numLines": 2
  }
}
```

</details>

---

### Assistant

_source line 67_

<details><summary>Logged reasoning block</summary>

```text
Good. Let me now check:

1. **0.752 in appendix**: This is in the temperature degeneracy table (tab:t_degeneracy), line 1057: "0.8 & 27.2 & 0.031 & 0.471 & 0.752 \\" — This is SJ mean at T=0.8, NOT the old SciERC oracle value. ✅ Different context, correct.

2. **0.776**: Not found anywhere. The task said "SciERC oracle: 0.752 → 0.776". 

Looking at tab:selection, I see Oracle = 0.778 ± 0.003, but the task mentions 0.776. Checking tab:fewnerd, I can derive the oracle from the greedy score of 0.644 plus the headroom of 13.2 percentage points, which gives 0.776. So there's a discrepancy between the two tables—tab:fewnerd implies an oracle of 0.776 while tab:selection shows 0.778, and the footnote appears to explain the SciERC values but cuts off mid-sentence.

The footnote clarifies that the slight differences between the tables stem from max-LP aggregation and single-seed versus multi-seed evaluation, which accounts for the 0.002 difference. I'm also verifying the other metrics: SciERC's LP improvement of +0.61pp checks out, CoNLL's degeneration at 59.1% is confirmed, and LLaMA's 86.4% degeneration appears only in the discussion section.

Now I'm moving through the appendix to validate the N-scaling tables and cross-check other critical values.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "659850cd-cf49-4b93-922f-372ee21ebaf4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Km8vJfkVAPHe1cBD4XwKo5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7892,
      "cache_read_input_tokens": 61425,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7892
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

_source line 68_

继续读取 appendix 中的 N-scaling、epoch confound 和其他关键表格。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "069ca7f9-c366-4a34-9e0a-6ca22da8d22f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Km8vJfkVAPHe1cBD4XwKo5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7892,
      "cache_read_input_tokens": 61425,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7892
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

_source line 69_

<details open><summary>🔧 Tool call — Read · `toolu_01MefnfLty7YRW6724WGAJdD`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "offset": 500,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "97b87312-c260-4eda-ba6c-a970f70bcb05",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Km8vJfkVAPHe1cBD4XwKo5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7892,
      "cache_read_input_tokens": 61425,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7892
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

_source line 70 · 2026-05-18T05:47:04.987Z_

<details><summary>↩ Tool result · `toolu_01MefnfLty7YRW6724WGAJdD`</summary>

```text
500	This eliminates format errors but may compress per-sample diversity by restricting the output space.\footnote{SciERC training used \texttt{enable\_thinking=True} (LLaMA Factory 0.9.4 default), injecting empty \texttt{&lt;think>&lt;/think>} blocks (4--5 tokens) into each training response with loss computation; CoNLL and WNUT explicitly set \texttt{enable\_thinking=False}. Constrained decoding at inference time enforces JSON-only output, suppressing thinking tokens. See \S\ref{sec:setup} and Limitations for discussion of this confound.}
501	
502	\section{Thinking Token Impact Analysis}\label{app:thinking_token}
503	
504	Qwen3-8B's SciERC checkpoint was trained with empty \texttt{&lt;think>&lt;/think>} blocks prepended to each response (\S\ref{sec:setup}).
505	We quantify the potential impact on LP scores through three complementary arguments.
506	
507	\paragraph{LP shift magnitude.}
508	Empty thinking tokens (mean 4.5 per sample) constitute 2.1\% of tokens on SciERC.
509	The estimated LP shift is 0.001 nats per token (2.68\% of the median within-instance LP range of 0.041 nats).
510	Because all samples share identical thinking-token LP offsets, cumulative LP rankings are invariant; mean LP changes selection for ${<}1.5\%$ of instances.
511	
512	\paragraph{Constant prefix cancellation.}
513	All $N$ samples within an instance share the same prompt and, under constrained decoding, the same absence of thinking tokens at inference time.
514	Any LP bias from the training-time thinking prefix is therefore a near-constant additive shift across all candidates within an instance, leaving within-instance LP \textit{rankings} unchanged.
515	
516	\paragraph{CoNLL control group.}
517	CoNLL and WNUT-17 checkpoints were trained without thinking tokens (\texttt{enable\_thinking=False}).
518	If thinking tokens caused LP compression on SciERC, CoNLL should exhibit lower tied fractions.
519	Instead, CoNLL shows \textit{higher} tied fractions at both temperatures (86.8\% at $T{=}1.0$, 95.8\% at $T{=}0.7$) than SciERC (60.3\% at $T{=}1.0$), directly contradicting the thinking-token hypothesis.
520	
521	\section{Log-Probability Score Compression}\label{app:logprob_ties}
522	
523	Under constrained decoding, log-probability scores are severely compressed within instances, limiting per-sample discrimination (Table~\ref{tab:logprob_ties}, Figure~\ref{fig:lp_range_cdf}).
524	The median within-instance LP range is only 0.041 nats; we use $\varepsilon{=}0.05$ as an illustrative threshold to characterize this compression.
525	At this cutpoint, 60.3\% of instances ($n{=}529$, excluding empty gold annotations) have a within-sample range below $\varepsilon$, and 75\% of pairwise comparisons are effective ties ($|\Delta|{<}0.026$).
526	The CDF rises smoothly with no cliff or discontinuity (Figure~\ref{fig:lp_range_cdf}); compression is a pervasive regime rather than a bimodal split.
527	This compression is stable across seeds: seed${=}456$ yields median LP range${=}0.040$ nats and tied fraction${=}62.2\%$ (vs.\ seed${=}42$: $0.041$ nats, $60.3\%$).
528	Seed~456 uses a different subtask flag (joint vs.\ ner for seeds 42 and 123); the LP distributions are statistically indistinguishable (median LP: 8.37 vs.\ 8.20 nats; Mann--Whitney $p{=}0.55$); the subtask change does not affect compression.
529	For comparison, SJ has only 12.5\% tied instances at the same threshold; SJ's advantage over LP for selection is one of score resolution, not information content.
530	
531	\begin{figure}[t]
532	\centering
533	\includegraphics[width=\columnwidth]{fig_lp_range_cdf}
534	\caption{CDF of within-instance LP range on SciERC NER ($N{=}8$, $n{=}529$). The median LP range is 0.041 nats (dashed line), below $\varepsilon{=}0.05$. The smooth CDF confirms compression is pervasive, not bimodal.}
535	\label{fig:lp_range_cdf}
536	\end{figure}
537	
538	\begin{table}[t]
539	\centering
540	\small
541	\caption{Log-probability score compression on SciERC NER ($N{=}8$, $n{=}529$). ``Tied'' = fraction of instances where within-instance LP range ${<}\varepsilon$.}
542	\label{tab:logprob_ties}
543	\begin{tabular}{lc}
544	\toprule
545	$\varepsilon$ threshold & Tied instances (\%) \\
546	\midrule
547	0.01 & 1.1\% \\
548	0.05 & 60.3\% \\
549	0.1  & ${\sim}$84\% \\
550	0.5  & ${\sim}$99\% \\
551	\bottomrule
552	\end{tabular}
553	\end{table}
554	
555	\paragraph{Non-tied subset.}
556	Among instances with LP range ${\geq}0.05$ ($n{=}210$, 40\% of total), log-probability selection \textit{significantly} outperforms single-sample ($+2.9$~pp F1, $p{=}0.004$), and within-instance $\rho(\text{LP}, \text{F1})$ rises from 0.08 (tied subset) to 0.39 (non-tied subset).
557	As a continuous complement to the binary tied/non-tied analysis, pooled within-instance $\rho(\text{LP}, \text{F1}){=}0.248$ across all instances confirms weak but positive per-sample signal; however, only 21.6\% of instances achieve $p{<}0.05$ significance, and $\rho(\text{LP range}, \text{F1 range}){=}0.328$ shows that instances with more LP spread also exhibit more F1 variability. LP carries information, but compression limits its exploitation.
558	A free-form NER decoding ablation (Appendix~\ref{app:freeform_ablation}) confirms this compression persists without constrained decoding.
559	
560	\paragraph{$\varepsilon$ sensitivity sweep (post-hoc exploratory).}
561	Table~\ref{tab:epsilon_sweep} sweeps the tied/non-tied threshold from $\varepsilon{=}0.01$ to $0.20$ as a post-hoc exploratory analysis characterizing how selection gain varies with compression severity.
562	The tied fraction increases smoothly with no cliff or discontinuity, and the selection gain $\Delta$ grows monotonically as the non-tied subset narrows to progressively higher-spread instances.
563	$\varepsilon{=}0.05$ yields the strongest statistical separation ($p{=}0.004$); at $\varepsilon{\geq}0.15$, the non-tied subset becomes too small for reliable inference ($n{\leq}36$).
564	
565	\begin{table}[t]
566	\centering
567	\small
568	\caption{$\varepsilon$ sensitivity sweep for LP selection on SciERC NER ($N{=}8$, seed${=}42$, $n{=}529$). ``Tied\%'' = fraction with within-instance LP range ${<}\varepsilon$. $\Delta$: selection F1 gain over single-sample on the non-tied subset. The tied fraction increases smoothly; $\varepsilon{=}0.05$ yields the strongest statistical separation.}
569	\label{tab:epsilon_sweep}
570	\begin{tabular}{ccccc}
571	\toprule
572	$\varepsilon$ & Tied\% & Non-tied $n$ & $\Delta$ (pp) & $p$ \\
573	\midrule
574	0.01 & 1.1\% & 523 & $+$0.58 & .21 \\
575	0.02 & 13.6\% & 457 & $+$0.83 & .15 \\
576	0.03 & 31.8\% & 361 & $+$1.31 & .079 \\
577	\textbf{0.05} & \textbf{60.3\%} & \textbf{210} & \textbf{$+$2.86} & \textbf{.004} \\
578	0.10 & 83.9\% & 85 & $+$3.69 & .034 \\
579	0.15 & 93.2\% & 36 & $+$4.15 & .11 \\
580	0.20 & 96.4\% & 19 & $+$4.59 & .13 \\
581	\bottomrule
582	\end{tabular}
583	\end{table}
584	
585	\paragraph{$\varepsilon$ robustness of selection F1.}\label{app:epsilon_robustness}
586	The preceding analysis stratifies LP by a tied/non-tied threshold; consistency-based signals (SJ, FK, VC, EM) also use $\varepsilon$ to define MBR-style proximity in selection.
587	Table~\ref{tab:epsilon_robustness} reports the maximum selection F1 variation across $\varepsilon \in [0, 0.2]$ for all signals and configurations.
588	At $\varepsilon{=}0.05$, consistency signals change by at most 1.09~pp (mean 0.21~pp), with EM completely $\varepsilon$-invariant (integer scoring); LP is the most sensitive (up to 3.65~pp across the full range), as expected.
589	Spearman $\rho$, the primary quality estimation metric throughout, is a continuous rank correlation that does not depend on any discretization threshold; the $\varepsilon$ parameter affects only the selection analysis.
590	
591	\begin{table}[t]
592	\centering
593	\small
594	\caption{Maximum selection F1 variation (pp) across $\varepsilon \in [0, 0.2]$. At $\varepsilon{=}0.05$ (used throughout), consistency signals change by ${\leq}1.09$~pp; EM is invariant (integer scoring). LP is most sensitive as $\varepsilon$ governs its tied/non-tied partition. SciERC: $n{=}529$; CoNLL: $n{=}2{,}756$.}
595	\label{tab:epsilon_robustness}
596	\begin{tabular}{lcccc}
597	\toprule
598	& \multicolumn{2}{c}{\textbf{SciERC}} & \multicolumn{2}{c}{\textbf{CoNLL}} \\
599	\cmidrule(lr){2-3} \cmidrule(lr){4-5}
600	Signal & Qwen & LLaMA & Qwen & LLaMA \\
601	\midrule
602	SJ & 0.92 & 1.45 & 0.99 & 0.18 \\
603	FK & 1.03 & 0.93 & 0.60 & 0.15 \\
604	VC & 2.33 & 0.53 & 0.72 & 0.18 \\
605	EM & 0.00 & 0.00 & 0.00 & 0.00 \\
606	LP & 3.65 & 2.58 & 3.00 & 0.31 \\
607	\bottomrule
608	\end{tabular}
609	\end{table}
610	
611	\paragraph{Non-tied subset analysis.}
612	Table~\ref{tab:nontied_main} presents the non-tied subset analysis referenced in \S\ref{sec:discussion}.
613	
614	\begin{table}[t]
615	\centering
616	\small
617	\caption{Non-tied subset analysis (SciERC, Qwen3-8B, $N{=}8$, $T{=}1.0$). Instances split at LP range $\varepsilon{=}0.05$. Within-instance $\rho$ and selection gain both concentrate in the non-tied subset. Full $\varepsilon$ sweep in Table~\ref{tab:epsilon_sweep}.}
618	\label{tab:nontied_main}
619	\begin{tabular}{lccc}
620	\toprule
621	Subset & $n$ & $\rho$(LP,F1) & LP $\Delta$ vs.\ greedy \\
622	\midrule
623	Tied (range ${<}0.05$) & 319 & 0.08 & ${\approx}0$ \\
624	Non-tied (range ${\geq}0.05$) & 210 & 0.39 & $+$2.9~pp ($p{=}0.004$) \\
625	\midrule
626	All instances & 529 & 0.248 & $+$0.2~pp ($p{=}0.29$) \\
627	\bottomrule
628	\end{tabular}
629	\end{table}
630	
631	\section{Consistency-Stratified Selection Analysis}\label{app:vc_quartile}
632	
633	Table~\ref{tab:vc_quartile} stratifies SciERC instances by voting confidence (VC) quartiles and reports selection $\Delta$ (gain over single-sample) for LP and SJ.
634	
635	\begin{table}[t]
636	\centering
637	\small
638	\caption{Selection $\Delta$ (pp over single-sample) stratified by VC quartile on SciERC ($N{=}8$, Qwen3-8B). Oracle headroom collapses at Q4; LP rankings are unreliable at Q1--Q2. Neither quartile supports consistent selection gains.}
639	\label{tab:vc_quartile}
640	\begin{tabular}{lcccc}
641	\toprule
642	Quartile & Mean VC & LP $\Delta$ & SJ $\Delta$ & Oracle (pp) \\
643	\midrule
644	\multicolumn{5}{l}{\textit{NER}} \\
645	Q1 (low) & 0.30 & $+$1.55 & $+$0.54 & 16.85 \\
646	Q2 & 0.51 & $-$0.65 & $-$1.89 & 14.35 \\
647	Q3 & 0.68 & $+$1.97 & $+$1.84 & 16.83 \\
648	Q4 (high) & 0.92 & $-$0.41 & $-$0.04 & 4.78 \\
649	\midrule
650	\multicolumn{5}{l}{\textit{$^\dagger$RE}} \\
651	Q1 (low) & --- & $-$3.56 & --- & --- \\
652	Q4 (high) & --- & $+$4.01 & --- & --- \\
653	\bottomrule
654	\end{tabular}
655	\end{table}
656	
657	The NER pattern reveals two complementary failure modes rather than a monotonic relationship between consistency and selection gain:
658	\begin{itemize}
659	\item \textbf{Q4 ceiling effect.} High-consistency instances (mean VC${=}0.92$) have oracle headroom of only 4.78~pp. Samples have already converged, leaving little room for any signal to improve selection.
660	\item \textbf{Q1--Q2 noise.} Low-consistency instances retain large headroom (14--17~pp) but LP rankings are unreliable, and LP rankings produce inconsistent $\Delta$ signs across quartiles.
661	\end{itemize}
662	
663	On $^\dagger$RE, the pattern differs: Q4 LP achieves $+4.01$~pp; LP may recover selection ability when high consistency coincides with structured output diversity. This is a single-dataset observation and should be interpreted cautiously.
664	
665	On CoNLL NER, Q3--Q4 instances have VC${=}1.0$ (all samples identical), and $\Delta{=}0$ universally; this ceiling effect is even more extreme than SciERC Q4.
666	
667	\section{Exploratory Extension to Relation Extraction}\label{app:re_extension}
668	
669	We extend the NER evaluation to relation extraction (RE) on SciERC as an exploratory single-benchmark analysis.
670	RE produces sets of (head, relation, tail) triples with partial overlap; 40\% of RE instances receive zero F1, and entity span errors account for 55.5\% of RE false negatives, a prerequisite failure that consistency signals cannot detect (\S\ref{app:additional}).
671	All RE results use Qwen3-8B unless noted; single-seed ($\text{seed}{=}42$) for $N{=}8$ analyses, 3-seed for $N{=}16$.
672	
673	\paragraph{Quality estimation.}
674	RE quality estimation is reported in Table~\ref{tab:multiseed} (3-seed means).
675	The signal ranking differs from NER: VC leads ($\rho{=}0.309{\pm}0.024$), but LP rises to \#2 ($\rho{=}0.297{\pm}0.022$), above FK, SJ, and EM, a reversal reflecting RE's higher sensitivity to per-sample scoring.
676	RE miscalibration is more severe than NER (ECE 0.109--0.339; Figure~\ref{fig:reliability}).
677	
678	\paragraph{Selection.}
679	Table~\ref{tab:re_cond_selection} presents RE selection at $N{=}8$: no signal outperforms single-sample (0.404) on the full set ($n{=}397$) or the non-zero subset ($n{=}238$), with 18.1~pp of unrealized oracle headroom.
680	At $N{=}16$ (Qwen3-4B, Table~\ref{tab:re_n16_selection}), LP is the sole positive signal ($\Delta{=}{+}0.7$~pp, $p{=}0.058$), consistent with LP being the strongest RE selection signal across scales.
681	
682	\paragraph{Scale ablation.}
683	At 4B scale (Qwen3-4B, $N{=}8$, $\text{seed}{=}42$), RE quality estimation shows FK $\rho{=}0.359$ and LP $\rho{=}0.351$, both above their 8B counterparts (FK 0.275, LP 0.266), while SJ declines ($0.267$ vs.\ $0.250$).
684	Selection remains below single-sample on RE ($\Delta$ up to $-3.4$~pp) despite 17.1~pp of oracle headroom.
685	
686	\paragraph{Free-form decoding.}
687	RE LP selection consistently reverses direction under free-form decoding ($+1.8{\pm}0.1$~pp across 4 seeds vs.\ $-0.9$~pp under constrained decoding at 8B; \S\ref{app:freeform_ablation}); constrained decoding's fixed template likely obscures LP signal in RE (\S\ref{app:mbr_discussion}).
688	
689	\section{RE Conditional Selection}\label{app:re_conditional_selection}
690	
691	Table~\ref{tab:re_cond_selection} extends the selection analysis to the RE non-zero F1 subset.
692	Of $n{=}397$ RE instances, 238 (60\%) have non-zero F1 and 159 (40\%) have zero F1.
693	All five signals underperform single-sample on both subsets.
694	On the non-zero subset, selection performance is \textit{worse} than on the full set (e.g., VC: $-10.0$~pp on non-zero vs.\ $-4.5$~pp on full set), because single-sample is already strong on non-zero instances (F1${=}0.674$) and signals actively select inferior samples.
695	Oracle headroom exists (0.757 vs.\ 0.674) but no signal exploits it, ruling out the 40\% zero-F1 floor effect as the explanation for RE selection failure.
696	
697	\begin{table}[t]
698	\centering
699	\small
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "9ba649e2-1df6-4b67-a39b-7e7f4bce79ce",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "This eliminates format errors but may compress per-sample diversity by restricting the output space.\\footnote{SciERC training used \\texttt{enable\\_thinking=True} (LLaMA Factory 0.9.4 default), injecting empty \\texttt{&lt;think>&lt;/think>} blocks (4--5 tokens) into each training response with loss computation; CoNLL and WNUT explicitly set \\texttt{enable\\_thinking=False}. Constrained decoding at inference time enforces JSON-only output, suppressing thinking tokens. See \\S\\ref{sec:setup} and Limitations for discussion of this confound.}\n\n\\section{Thinking Token Impact Analysis}\\label{app:thinking_token}\n\nQwen3-8B's SciERC checkpoint was trained with empty \\texttt{&lt;think>&lt;/think>} blocks prepended to each response (\\S\\ref{sec:setup}).\nWe quantify the potential impact on LP scores through three complementary arguments.\n\n\\paragraph{LP shift magnitude.}\nEmpty thinking tokens (mean 4.5 per sample) constitute 2.1\\% of tokens on SciERC.\nThe estimated LP shift is 0.001 nats per token (2.68\\% of the median within-instance LP range of 0.041 nats).\nBecause all samples share identical thinking-token LP offsets, cumulative LP rankings are invariant; mean LP changes selection for ${<}1.5\\%$ of instances.\n\n\\paragraph{Constant prefix cancellation.}\nAll $N$ samples within an instance share the same prompt and, under constrained decoding, the same absence of thinking tokens at inference time.\nAny LP bias from the training-time thinking prefix is therefore a near-constant additive shift across all candidates within an instance, leaving within-instance LP \\textit{rankings} unchanged.\n\n\\paragraph{CoNLL control group.}\nCoNLL and WNUT-17 checkpoints were trained without thinking tokens (\\texttt{enable\\_thinking=False}).\nIf thinking tokens caused LP compression on SciERC, CoNLL should exhibit lower tied fractions.\nInstead, CoNLL shows \\textit{higher} tied fractions at both temperatures (86.8\\% at $T{=}1.0$, 95.8\\% at $T{=}0.7$) than SciERC (60.3\\% at $T{=}1.0$), directly contradicting the thinking-token hypothesis.\n\n\\section{Log-Probability Score Compression}\\label{app:logprob_ties}\n\nUnder constrained decoding, log-probability scores are severely compressed within instances, limiting per-sample discrimination (Table~\\ref{tab:logprob_ties}, Figure~\\ref{fig:lp_range_cdf}).\nThe median within-instance LP range is only 0.041 nats; we use $\\varepsilon{=}0.05$ as an illustrative threshold to characterize this compression.\nAt this cutpoint, 60.3\\% of instances ($n{=}529$, excluding empty gold annotations) have a within-sample range below $\\varepsilon$, and 75\\% of pairwise comparisons are effective ties ($|\\Delta|{<}0.026$).\nThe CDF rises smoothly with no cliff or discontinuity (Figure~\\ref{fig:lp_range_cdf}); compression is a pervasive regime rather than a bimodal split.\nThis compression is stable across seeds: seed${=}456$ yields median LP range${=}0.040$ nats and tied fraction${=}62.2\\%$ (vs.\\ seed${=}42$: $0.041$ nats, $60.3\\%$).\nSeed~456 uses a different subtask flag (joint vs.\\ ner for seeds 42 and 123); the LP distributions are statistically indistinguishable (median LP: 8.37 vs.\\ 8.20 nats; Mann--Whitney $p{=}0.55$); the subtask change does not affect compression.\nFor comparison, SJ has only 12.5\\% tied instances at the same threshold; SJ's advantage over LP for selection is one of score resolution, not information content.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_lp_range_cdf}\n\\caption{CDF of within-instance LP range on SciERC NER ($N{=}8$, $n{=}529$). The median LP range is 0.041 nats (dashed line), below $\\varepsilon{=}0.05$. The smooth CDF confirms compression is pervasive, not bimodal.}\n\\label{fig:lp_range_cdf}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Log-probability score compression on SciERC NER ($N{=}8$, $n{=}529$). ``Tied'' = fraction of instances where within-instance LP range ${<}\\varepsilon$.}\n\\label{tab:logprob_ties}\n\\begin{tabular}{lc}\n\\toprule\n$\\varepsilon$ threshold & Tied instances (\\%) \\\\\n\\midrule\n0.01 & 1.1\\% \\\\\n0.05 & 60.3\\% \\\\\n0.1  & ${\\sim}$84\\% \\\\\n0.5  & ${\\sim}$99\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Non-tied subset.}\nAmong instances with LP range ${\\geq}0.05$ ($n{=}210$, 40\\% of total), log-probability selection \\textit{significantly} outperforms single-sample ($+2.9$~pp F1, $p{=}0.004$), and within-instance $\\rho(\\text{LP}, \\text{F1})$ rises from 0.08 (tied subset) to 0.39 (non-tied subset).\nAs a continuous complement to the binary tied/non-tied analysis, pooled within-instance $\\rho(\\text{LP}, \\text{F1}){=}0.248$ across all instances confirms weak but positive per-sample signal; however, only 21.6\\% of instances achieve $p{<}0.05$ significance, and $\\rho(\\text{LP range}, \\text{F1 range}){=}0.328$ shows that instances with more LP spread also exhibit more F1 variability. LP carries information, but compression limits its exploitation.\nA free-form NER decoding ablation (Appendix~\\ref{app:freeform_ablation}) confirms this compression persists without constrained decoding.\n\n\\paragraph{$\\varepsilon$ sensitivity sweep (post-hoc exploratory).}\nTable~\\ref{tab:epsilon_sweep} sweeps the tied/non-tied threshold from $\\varepsilon{=}0.01$ to $0.20$ as a post-hoc exploratory analysis characterizing how selection gain varies with compression severity.\nThe tied fraction increases smoothly with no cliff or discontinuity, and the selection gain $\\Delta$ grows monotonically as the non-tied subset narrows to progressively higher-spread instances.\n$\\varepsilon{=}0.05$ yields the strongest statistical separation ($p{=}0.004$); at $\\varepsilon{\\geq}0.15$, the non-tied subset becomes too small for reliable inference ($n{\\leq}36$).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{$\\varepsilon$ sensitivity sweep for LP selection on SciERC NER ($N{=}8$, seed${=}42$, $n{=}529$). ``Tied\\%'' = fraction with within-instance LP range ${<}\\varepsilon$. $\\Delta$: selection F1 gain over single-sample on the non-tied subset. The tied fraction increases smoothly; $\\varepsilon{=}0.05$ yields the strongest statistical separation.}\n\\label{tab:epsilon_sweep}\n\\begin{tabular}{ccccc}\n\\toprule\n$\\varepsilon$ & Tied\\% & Non-tied $n$ & $\\Delta$ (pp) & $p$ \\\\\n\\midrule\n0.01 & 1.1\\% & 523 & $+$0.58 & .21 \\\\\n0.02 & 13.6\\% & 457 & $+$0.83 & .15 \\\\\n0.03 & 31.8\\% & 361 & $+$1.31 & .079 \\\\\n\\textbf{0.05} & \\textbf{60.3\\%} & \\textbf{210} & \\textbf{$+$2.86} & \\textbf{.004} \\\\\n0.10 & 83.9\\% & 85 & $+$3.69 & .034 \\\\\n0.15 & 93.2\\% & 36 & $+$4.15 & .11 \\\\\n0.20 & 96.4\\% & 19 & $+$4.59 & .13 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{$\\varepsilon$ robustness of selection F1.}\\label{app:epsilon_robustness}\nThe preceding analysis stratifies LP by a tied/non-tied threshold; consistency-based signals (SJ, FK, VC, EM) also use $\\varepsilon$ to define MBR-style proximity in selection.\nTable~\\ref{tab:epsilon_robustness} reports the maximum selection F1 variation across $\\varepsilon \\in [0, 0.2]$ for all signals and configurations.\nAt $\\varepsilon{=}0.05$, consistency signals change by at most 1.09~pp (mean 0.21~pp), with EM completely $\\varepsilon$-invariant (integer scoring); LP is the most sensitive (up to 3.65~pp across the full range), as expected.\nSpearman $\\rho$, the primary quality estimation metric throughout, is a continuous rank correlation that does not depend on any discretization threshold; the $\\varepsilon$ parameter affects only the selection analysis.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Maximum selection F1 variation (pp) across $\\varepsilon \\in [0, 0.2]$. At $\\varepsilon{=}0.05$ (used throughout), consistency signals change by ${\\leq}1.09$~pp; EM is invariant (integer scoring). LP is most sensitive as $\\varepsilon$ governs its tied/non-tied partition. SciERC: $n{=}529$; CoNLL: $n{=}2{,}756$.}\n\\label{tab:epsilon_robustness}\n\\begin{tabular}{lcccc}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{SciERC}} & \\multicolumn{2}{c}{\\textbf{CoNLL}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nSignal & Qwen & LLaMA & Qwen & LLaMA \\\\\n\\midrule\nSJ & 0.92 & 1.45 & 0.99 & 0.18 \\\\\nFK & 1.03 & 0.93 & 0.60 & 0.15 \\\\\nVC & 2.33 & 0.53 & 0.72 & 0.18 \\\\\nEM & 0.00 & 0.00 & 0.00 & 0.00 \\\\\nLP & 3.65 & 2.58 & 3.00 & 0.31 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Non-tied subset analysis.}\nTable~\\ref{tab:nontied_main} presents the non-tied subset analysis referenced in \\S\\ref{sec:discussion}.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Non-tied subset analysis (SciERC, Qwen3-8B, $N{=}8$, $T{=}1.0$). Instances split at LP range $\\varepsilon{=}0.05$. Within-instance $\\rho$ and selection gain both concentrate in the non-tied subset. Full $\\varepsilon$ sweep in Table~\\ref{tab:epsilon_sweep}.}\n\\label{tab:nontied_main}\n\\begin{tabular}{lccc}\n\\toprule\nSubset & $n$ & $\\rho$(LP,F1) & LP $\\Delta$ vs.\\ greedy \\\\\n\\midrule\nTied (range ${<}0.05$) & 319 & 0.08 & ${\\approx}0$ \\\\\nNon-tied (range ${\\geq}0.05$) & 210 & 0.39 & $+$2.9~pp ($p{=}0.004$) \\\\\n\\midrule\nAll instances & 529 & 0.248 & $+$0.2~pp ($p{=}0.29$) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Consistency-Stratified Selection Analysis}\\label{app:vc_quartile}\n\nTable~\\ref{tab:vc_quartile} stratifies SciERC instances by voting confidence (VC) quartiles and reports selection $\\Delta$ (gain over single-sample) for LP and SJ.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Selection $\\Delta$ (pp over single-sample) stratified by VC quartile on SciERC ($N{=}8$, Qwen3-8B). Oracle headroom collapses at Q4; LP rankings are unreliable at Q1--Q2. Neither quartile supports consistent selection gains.}\n\\label{tab:vc_quartile}\n\\begin{tabular}{lcccc}\n\\toprule\nQuartile & Mean VC & LP $\\Delta$ & SJ $\\Delta$ & Oracle (pp) \\\\\n\\midrule\n\\multicolumn{5}{l}{\\textit{NER}} \\\\\nQ1 (low) & 0.30 & $+$1.55 & $+$0.54 & 16.85 \\\\\nQ2 & 0.51 & $-$0.65 & $-$1.89 & 14.35 \\\\\nQ3 & 0.68 & $+$1.97 & $+$1.84 & 16.83 \\\\\nQ4 (high) & 0.92 & $-$0.41 & $-$0.04 & 4.78 \\\\\n\\midrule\n\\multicolumn{5}{l}{\\textit{$^\\dagger$RE}} \\\\\nQ1 (low) & --- & $-$3.56 & --- & --- \\\\\nQ4 (high) & --- & $+$4.01 & --- & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe NER pattern reveals two complementary failure modes rather than a monotonic relationship between consistency and selection gain:\n\\begin{itemize}\n\\item \\textbf{Q4 ceiling effect.} High-consistency instances (mean VC${=}0.92$) have oracle headroom of only 4.78~pp. Samples have already converged, leaving little room for any signal to improve selection.\n\\item \\textbf{Q1--Q2 noise.} Low-consistency instances retain large headroom (14--17~pp) but LP rankings are unreliable, and LP rankings produce inconsistent $\\Delta$ signs across quartiles.\n\\end{itemize}\n\nOn $^\\dagger$RE, the pattern differs: Q4 LP achieves $+4.01$~pp; LP may recover selection ability when high consistency coincides with structured output diversity. This is a single-dataset observation and should be interpreted cautiously.\n\nOn CoNLL NER, Q3--Q4 instances have VC${=}1.0$ (all samples identical), and $\\Delta{=}0$ universally; this ceiling effect is even more extreme than SciERC Q4.\n\n\\section{Exploratory Extension to Relation Extraction}\\label{app:re_extension}\n\nWe extend the NER evaluation to relation extraction (RE) on SciERC as an exploratory single-benchmark analysis.\nRE produces sets of (head, relation, tail) triples with partial overlap; 40\\% of RE instances receive zero F1, and entity span errors account for 55.5\\% of RE false negatives, a prerequisite failure that consistency signals cannot detect (\\S\\ref{app:additional}).\nAll RE results use Qwen3-8B unless noted; single-seed ($\\text{seed}{=}42$) for $N{=}8$ analyses, 3-seed for $N{=}16$.\n\n\\paragraph{Quality estimation.}\nRE quality estimation is reported in Table~\\ref{tab:multiseed} (3-seed means).\nThe signal ranking differs from NER: VC leads ($\\rho{=}0.309{\\pm}0.024$), but LP rises to \\#2 ($\\rho{=}0.297{\\pm}0.022$), above FK, SJ, and EM, a reversal reflecting RE's higher sensitivity to per-sample scoring.\nRE miscalibration is more severe than NER (ECE 0.109--0.339; Figure~\\ref{fig:reliability}).\n\n\\paragraph{Selection.}\nTable~\\ref{tab:re_cond_selection} presents RE selection at $N{=}8$: no signal outperforms single-sample (0.404) on the full set ($n{=}397$) or the non-zero subset ($n{=}238$), with 18.1~pp of unrealized oracle headroom.\nAt $N{=}16$ (Qwen3-4B, Table~\\ref{tab:re_n16_selection}), LP is the sole positive signal ($\\Delta{=}{+}0.7$~pp, $p{=}0.058$), consistent with LP being the strongest RE selection signal across scales.\n\n\\paragraph{Scale ablation.}\nAt 4B scale (Qwen3-4B, $N{=}8$, $\\text{seed}{=}42$), RE quality estimation shows FK $\\rho{=}0.359$ and LP $\\rho{=}0.351$, both above their 8B counterparts (FK 0.275, LP 0.266), while SJ declines ($0.267$ vs.\\ $0.250$).\nSelection remains below single-sample on RE ($\\Delta$ up to $-3.4$~pp) despite 17.1~pp of oracle headroom.\n\n\\paragraph{Free-form decoding.}\nRE LP selection consistently reverses direction under free-form decoding ($+1.8{\\pm}0.1$~pp across 4 seeds vs.\\ $-0.9$~pp under constrained decoding at 8B; \\S\\ref{app:freeform_ablation}); constrained decoding's fixed template likely obscures LP signal in RE (\\S\\ref{app:mbr_discussion}).\n\n\\section{RE Conditional Selection}\\label{app:re_conditional_selection}\n\nTable~\\ref{tab:re_cond_selection} extends the selection analysis to the RE non-zero F1 subset.\nOf $n{=}397$ RE instances, 238 (60\\%) have non-zero F1 and 159 (40\\%) have zero F1.\nAll five signals underperform single-sample on both subsets.\nOn the non-zero subset, selection performance is \\textit{worse} than on the full set (e.g., VC: $-10.0$~pp on non-zero vs.\\ $-4.5$~pp on full set), because single-sample is already strong on non-zero instances (F1${=}0.674$) and signals actively select inferior samples.\nOracle headroom exists (0.757 vs.\\ 0.674) but no signal exploits it, ruling out the 40\\% zero-F1 floor effect as the explanation for RE selection failure.\n\n\\begin{table}[t]\n\\centering\n\\small",
      "numLines": 200,
      "startLine": 500,
      "totalLines": 1354
    }
  }
}
```

</details>

---

### Tool call

_source line 71_

<details open><summary>🔧 Tool call — Read · `toolu_014rtAVqrgp5gYdSxhqCugWo`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "offset": 700,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "08f19905-7f26-4e17-9409-6224493b15f2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Km8vJfkVAPHe1cBD4XwKo5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7892,
      "cache_read_input_tokens": 61425,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7892
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

_source line 72 · 2026-05-18T05:47:05.799Z_

<details><summary>↩ Tool result · `toolu_014rtAVqrgp5gYdSxhqCugWo`</summary>

```text
700	\caption{RE selection F1 (macro, instance-averaged) on SciERC ($N{=}8$, $T{=}1.0$). Full set ($n{=}397$) and non-zero F1 subset ($n{=}238$). No signal outperforms greedy on either subset.}
701	\label{tab:re_cond_selection}
702	\begin{tabular}{lcc}
703	\toprule
704	Method & Full ($n{=}397$) & Non-zero ($n{=}238$) \\
705	\midrule
706	Oracle & 0.585 & 0.757 \\
707	\midrule
708	LP & 0.395 & 0.600 \\
709	SJ & 0.386 & 0.604 \\
710	EM & 0.372 & 0.583 \\
711	VC & 0.359 & 0.574 \\
712	\midrule
713	Greedy & 0.404 & 0.674 \\
714	\bottomrule
715	\end{tabular}
716	\end{table}
717	
718	\section{RE $N{=}16$ Selection Analysis}\label{app:re_n16_selection}
719	
720	Table~\ref{tab:re_n16_selection} extends the selection analysis to RE at $N{=}16$ with 3-seed statistics.
721	All four consistency signals underperform single-sample, with EM showing the largest deficit ($\Delta{=}{-}1.5$~pp, Fisher $p{>}0.99$).
722	LP is the only positive signal ($\Delta{=}{+}0.7$~pp, Fisher $p{=}0.058$), driven primarily by seed~456 ($\Delta{=}{+}1.5$~pp, $p{=}0.026$); the remaining seeds show smaller effects ($+0.1$ and $+0.6$~pp, $p{>}0.20$).
723	Even the most favorable seed captures only ${\sim}9\%$ of the 17.1~pp oracle headroom.
724	This cross-task consistency (LP as the only viable selection signal on both NER and RE) reinforces the persistent limitation of instance-level signals for candidate ranking across tested regimes.
725	
726	\begin{table}[t]
727	\centering
728	\small
729	\caption{RE best-of-$N$ selection F1 (macro, instance-averaged) on SciERC (Qwen3-4B, $N{=}16$, $T{=}1.0$, 3-seed mean${\pm}\sigma$, $n{=}551$). Fisher combined $p$ vs.\ greedy. LP is the only signal with positive $\Delta$. $\sigma$ is population standard deviation over 3 seeds.}
730	\label{tab:re_n16_selection}
731	\begin{tabular}{lccc}
732	\toprule
733	Method & F1 & $\Delta$ (pp) & $p$(Fisher) \\
734	\midrule
735	Oracle & $.463{\pm}.006$ & $+$17.1 & --- \\
736	\midrule
737	LP & $\mathbf{.299}{\pm}.007$ & $+$0.7 & .058 \\
738	VC & $.284{\pm}.002$ & $-$0.8 & .973 \\
739	FK & $.283{\pm}.005$ & $-$0.9 & .985 \\
740	SJ & $.281{\pm}.005$ & $-$1.0 & .993 \\
741	EM & $.277{\pm}.007$ & $-$1.5 & .999 \\
742	\midrule
743	Greedy & $.291{\pm}.000$ & --- & --- \\
744	Random & $.262{\pm}.001$ & $-$2.9 & --- \\
745	\bottomrule
746	\end{tabular}
747	\end{table}
748	
749	\section{MBR Decoding and Task-Specific Interactions}\label{app:mbr_discussion}
750	
751	\paragraph{Connection to MBR decoding.}
752	Our selection strategies instantiate minimum Bayes risk (MBR) decoding \cite{eikema2022sampling, muller2021understanding}: each selects $\hat{y} = \arg\max_{y_i} \sum_{j \neq i} U(y_i, y_j)$ with utility $U$ defined by SJ, EM, or entity overlap.
753	Despite MBR's success in machine translation \cite{freitag2022high} and its extension to summarization, code generation, and captioning \cite{jinnai2024mbr}, all variants fail here: despite positive within-instance utility--F1 correlation, selection gains are limited by instance degeneracy, the core of the correlation-selection gap.
754	\citet{eikema2025structured} study structure-conditional MBR decoding and find that standard utility functions degrade on structured outputs, consistent with our finding that consensus-proximity selection fails in IE despite its success in machine translation.
755	
756	\paragraph{Task-specific decoding interactions.}
757	The free-form ablation reveals divergent behavior across tasks.
758	On RE, LP selection flips from $-0.68$~pp (constrained) to $+1.69$~pp (free-form; preliminary, single RE benchmark), a reversal that spans all 7 relation types and is driven by selective variance reallocation ($p{<}0.0001$).
759	The win/loss ratio shifts from 36:59 (constrained) to 45:45 (free-form), with the gains concentrated on relation-dense instances (mean 3.3 gold relations).
760	This interaction does not generalize to NER, where selection remains negligible under both regimes.
761	This ablation uses a single seed (seed${=}42$); whether the RE reversal replicates across seeds and generalizes to other RE benchmarks warrants further investigation.
762	The non-tied subset ($n{=}210$) is partially reshuffled under free-form decoding: Jaccard similarity between the constrained and free-form non-tied sets is 0.472: 87 instances newly gain LP discrimination while others lose it, and the newly non-tied subset shows a $3{\times}$ increase in within-instance LP range for the newly non-tied subset.
763	Despite this reshuffling, aggregate NER selection gains remain negligible. Score compression is not a fixed property of specific instances but rather a pervasive regime that shifts across instances without producing net selection improvement.
764	Free-form decoding also slightly improves quality estimation (NER VC $\rho$: 0.379$\to$0.409), though this does not translate to selection gains.
765	
766	\section{Free-Form Decoding Ablation}\label{app:freeform_ablation}
767	
768	Table~\ref{tab:freeform_ablation} compares constrained and free-form decoding across four dimensions on SciERC ($N{=}8$, $T{=}1.0$, Qwen3-8B; seed${=}42$ shown, 4-seed RE statistics below).
769	Free-form decoding removes grammar constraints entirely; outputs are parsed post-hoc (parse rate 99.95\%, 4406/4408).
770	LP score distributions are nearly identical across regimes (Panel~A: within-instance std ratio $0.97{\times}$), and NER selection gains remain negligible under both regimes (Panel~B).
771	RE LP selection consistently reverses direction under free-form decoding across 4 seeds: $+1.84{\pm}0.12$~pp (seeds 42/123/456/789: $+1.69$, $+1.76$, $+2.00$, $+1.91$~pp) vs.\ $-0.68$~pp constrained.
772	The constrained reference ($-0.68$~pp) uses the ablation-matched baseline; the primary experiment (Table~\ref{tab:selection}) yields $-0.9$~pp on the same gold-filtered set.
773	Quality estimation improves modestly for most signals under free-form decoding (Panel~C), with the largest gain for FK ($+0.053$ NER, $+0.039$ RE).
774	
775	\begin{table*}[t]
776	\centering
777	\caption{Comparison of constrained vs.\ free-form decoding on SciERC (Qwen3-8B, $N{=}8$, $T{=}1.0$, seed${=}42$; RE selection gap replicates across 4 seeds: $+1.84{\pm}0.12$~pp).}
778	\label{tab:freeform_ablation}
779	
780	\vspace{2pt}
781	{\small\textsc{Panel A: Logprob Distribution}}
782	\vspace{2pt}
783	
784	\begin{tabular}{lccc}
785	\toprule
786	Metric & Constrained & Free-form & $\Delta$ \\
787	\midrule
788	Mean LP std        & 0.0206 & 0.0199 & $-$0.0007 \\
789	Mean LP range      & 0.0623 & 0.0599 & $-$0.0024 \\
790	Tied fraction ($\varepsilon{=}0.05$) & 59.7\% & 57.7\% & $-$2.0\,pp \\
791	\bottomrule
792	\end{tabular}
793	
794	\vspace{8pt}
795	
796	{\small\textsc{Panel B: Selection F1}}
797	\vspace{2pt}
798	
799	\begin{tabular}{llccc}
800	\toprule
801	Task & Method & Constrained & Free-form & $\Delta$ \\
802	\midrule
803	\multirow{3}{*}{NER}
804	  & Greedy        & 0.6182 & 0.6204 & $+$0.0022 \\
805	  & LP-selected   & 0.6241 & 0.6222 & $-$0.0019 \\
806	  & Selection gap & $+$0.0059 & $+$0.0018 & $-$0.0041 \\
807	\midrule
808	\multirow{3}{*}{RE}
809	  & Greedy        & 0.2913 & 0.2880 & $-$0.0033 \\
810	  & LP-selected   & 0.2845 & 0.3050 & \textbf{$+$0.0205} \\
811	  & Selection gap & $-$0.0068 & $+$0.0169 & \textbf{$+$0.0237} \\
812	\bottomrule
813	\end{tabular}
814	
815	\vspace{8pt}
816	
817	{\small\textsc{Panel C: QE Signal Quality (Spearman $\rho$)}}
818	\vspace{2pt}
819	
820	\begin{tabular}{l ccc ccc}
821	\toprule
822	 & \multicolumn{3}{c}{NER ($n{=}529$)} & \multicolumn{3}{c}{RE ($n{=}397$)} \\
823	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
824	Signal & Constr. & Free & $\Delta$ & Constr. & Free & $\Delta$ \\
825	\midrule
826	SJ & 0.360 & 0.377 & $+$0.018 & 0.250 & 0.273 & $+$0.023 \\
827	FK & 0.267 & 0.320 & $+$0.053 & 0.275 & 0.315 & $+$0.039 \\
828	LP & 0.205 & 0.213 & $+$0.008 & 0.266 & 0.304 & $+$0.038 \\
829	EM & 0.295 & 0.317 & $+$0.023 & 0.134 & 0.137 & $+$0.002 \\
830	VC & 0.379 & 0.409 & $+$0.030 & 0.350 & 0.323 & $-$0.026 \\
831	\bottomrule
832	\end{tabular}
833	
834	\vspace{8pt}
835	
836	{\small\textsc{Panel D: Parse Rate (Free-form)}}
837	\vspace{2pt}
838	
839	\begin{tabular}{lc}
840	\toprule
841	Metric & Value \\
842	\midrule
843	Total samples          & 4408 \\
844	Parse rate             & 99.95\% \\
845	Instances 8/8 valid    & 549\,/\,551 (99.6\%) \\
846	\bottomrule
847	\end{tabular}
848	
849	\end{table*}
850	
851	\paragraph{CoNLL NER free-form results.}
852	Extending the free-form ablation to CoNLL NER (Qwen3-8B, 4 seeds, $N{=}8$, $T{=}1.0$), LP range median is $0.058{\pm}0.007$ across seeds, higher than SciERC ($0.041$) but still compressed given CoNLL's 86.8\% tied fraction under constrained decoding.
853	Free-form decoding reduces the tied fraction modestly, yet selection remains below single-sample: LP-selected F1${=}0.896$ vs.\ single-sample $0.904$ ($\Delta{=}{-}0.77$~pp).
854	Quality estimation under free-form decoding yields SJ $\rho{=}0.461$, EM $\rho{=}0.471$, LP $\rho{=}0.326$, comparable to constrained results (Table~\ref{tab:quality_estimation}).
855	The failure to improve selection despite reduced compression is consistent with CoNLL's low oracle headroom (4.25~pp at $N{=}8$), which limits the selection space regardless of score distribution quality.
856	
857	\section{LP Selection Failure Stability}\label{app:lp_failure_stability}
858	
859	We analyze RE LP selection failures across three random seeds (constrained decoding, $N{=}8$, $T{=}1.0$, Qwen3-8B) to assess whether failures are systematic or stochastic.
860	
861	\paragraph{Pairwise overlap.}
862	LP selection failures (instances where LP-selected F1 $<$ single-sample F1) show moderate cross-seed stability: the average pairwise Jaccard similarity is 0.42 (range: 0.38--0.46); failures are partially systematic (driven by instance complexity) but not fully deterministic.
863	The 3-way intersection contains 34 instances (27.9\% of any-seed failures), which constitutes a stable failure core.
864	
865	\paragraph{Instance complexity drives failure.}
866	Table~\ref{tab:stable_failures} stratifies instances by failure stability.
867	Stable failures (all 3 seeds) involve more gold relations (2.12 vs.\ 1.62 for never-fail instances) and higher single-sample F1 (0.688 vs.\ 0.429); LP mis-selects on instances where the model already performs well, precisely the instances where selection would be most valuable.
868	Failure rate increases monotonically with gold relation count: 4.3\% at 1 relation, 20.7\% at 3 relations, 26.2\% at 6 relations.
869	
870	\begin{table}[t]
871	\centering
872	\small
873	\caption{RE LP selection failure stability across 3 seeds (SciERC, $N{=}8$). Stable failures concentrate on relation-dense instances with high single-sample F1.}
874	\label{tab:stable_failures}
875	\begin{tabular}{lcccc}
876	\toprule
877	Group & $n$ & Gold rels & Greedy F1 & LP $\Delta$F1 \\
878	\midrule
879	Stable fail (3 seeds) & 34 & 2.12 & 0.688 & $-$0.499 \\
880	Fail 2+ seeds & 26 & 2.46 & 0.774 & $-$0.450 \\
881	Fail 1 seed & 62 & 2.32 & 0.692 & $-$0.239 \\
882	Never fail & 429 & 1.62 & 0.429 & $+$0.041 \\
883	\bottomrule
884	\end{tabular}
885	\end{table}
886	
887	\paragraph{Flip instances.}
888	Only 5 RE instances with gold relations flip from LP failure (constrained) to LP success (free-form), with mean gold relation count 3.67 (well above the population mean of 1.86).
889	These instances show large constrained LP errors ($\Delta{=}{-}0.430$) that reverse under free-form decoding ($\Delta{=}{+}0.503$), but their rarity (5/397) confirms that the RE selection flip is driven by aggregate variance reallocation rather than systematic instance-level correction.
890	
891	\section{$N$-Scaling Detailed Analysis}\label{app:n_scaling}
892	
893	Tables~\ref{tab:n-scaling}--\ref{tab:sigma-comparison} provide detailed $N$-scaling analysis on Qwen3-8B SciERC with 3-seed statistics.
894	
895	\begin{table}[t]
896	\centering
897	\caption{Effect of sample pool size on signal quality (Qwen3-8B, SciERC, 3-seed mean Spearman $\rho$).}
898	\label{tab:n-scaling}
899	\small
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "5403dd4d-c2e3-4422-bc15-c1c6a0f7b14b",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "\\caption{RE selection F1 (macro, instance-averaged) on SciERC ($N{=}8$, $T{=}1.0$). Full set ($n{=}397$) and non-zero F1 subset ($n{=}238$). No signal outperforms greedy on either subset.}\n\\label{tab:re_cond_selection}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & Full ($n{=}397$) & Non-zero ($n{=}238$) \\\\\n\\midrule\nOracle & 0.585 & 0.757 \\\\\n\\midrule\nLP & 0.395 & 0.600 \\\\\nSJ & 0.386 & 0.604 \\\\\nEM & 0.372 & 0.583 \\\\\nVC & 0.359 & 0.574 \\\\\n\\midrule\nGreedy & 0.404 & 0.674 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{RE $N{=}16$ Selection Analysis}\\label{app:re_n16_selection}\n\nTable~\\ref{tab:re_n16_selection} extends the selection analysis to RE at $N{=}16$ with 3-seed statistics.\nAll four consistency signals underperform single-sample, with EM showing the largest deficit ($\\Delta{=}{-}1.5$~pp, Fisher $p{>}0.99$).\nLP is the only positive signal ($\\Delta{=}{+}0.7$~pp, Fisher $p{=}0.058$), driven primarily by seed~456 ($\\Delta{=}{+}1.5$~pp, $p{=}0.026$); the remaining seeds show smaller effects ($+0.1$ and $+0.6$~pp, $p{>}0.20$).\nEven the most favorable seed captures only ${\\sim}9\\%$ of the 17.1~pp oracle headroom.\nThis cross-task consistency (LP as the only viable selection signal on both NER and RE) reinforces the persistent limitation of instance-level signals for candidate ranking across tested regimes.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{RE best-of-$N$ selection F1 (macro, instance-averaged) on SciERC (Qwen3-4B, $N{=}16$, $T{=}1.0$, 3-seed mean${\\pm}\\sigma$, $n{=}551$). Fisher combined $p$ vs.\\ greedy. LP is the only signal with positive $\\Delta$. $\\sigma$ is population standard deviation over 3 seeds.}\n\\label{tab:re_n16_selection}\n\\begin{tabular}{lccc}\n\\toprule\nMethod & F1 & $\\Delta$ (pp) & $p$(Fisher) \\\\\n\\midrule\nOracle & $.463{\\pm}.006$ & $+$17.1 & --- \\\\\n\\midrule\nLP & $\\mathbf{.299}{\\pm}.007$ & $+$0.7 & .058 \\\\\nVC & $.284{\\pm}.002$ & $-$0.8 & .973 \\\\\nFK & $.283{\\pm}.005$ & $-$0.9 & .985 \\\\\nSJ & $.281{\\pm}.005$ & $-$1.0 & .993 \\\\\nEM & $.277{\\pm}.007$ & $-$1.5 & .999 \\\\\n\\midrule\nGreedy & $.291{\\pm}.000$ & --- & --- \\\\\nRandom & $.262{\\pm}.001$ & $-$2.9 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{MBR Decoding and Task-Specific Interactions}\\label{app:mbr_discussion}\n\n\\paragraph{Connection to MBR decoding.}\nOur selection strategies instantiate minimum Bayes risk (MBR) decoding \\cite{eikema2022sampling, muller2021understanding}: each selects $\\hat{y} = \\arg\\max_{y_i} \\sum_{j \\neq i} U(y_i, y_j)$ with utility $U$ defined by SJ, EM, or entity overlap.\nDespite MBR's success in machine translation \\cite{freitag2022high} and its extension to summarization, code generation, and captioning \\cite{jinnai2024mbr}, all variants fail here: despite positive within-instance utility--F1 correlation, selection gains are limited by instance degeneracy, the core of the correlation-selection gap.\n\\citet{eikema2025structured} study structure-conditional MBR decoding and find that standard utility functions degrade on structured outputs, consistent with our finding that consensus-proximity selection fails in IE despite its success in machine translation.\n\n\\paragraph{Task-specific decoding interactions.}\nThe free-form ablation reveals divergent behavior across tasks.\nOn RE, LP selection flips from $-0.68$~pp (constrained) to $+1.69$~pp (free-form; preliminary, single RE benchmark), a reversal that spans all 7 relation types and is driven by selective variance reallocation ($p{<}0.0001$).\nThe win/loss ratio shifts from 36:59 (constrained) to 45:45 (free-form), with the gains concentrated on relation-dense instances (mean 3.3 gold relations).\nThis interaction does not generalize to NER, where selection remains negligible under both regimes.\nThis ablation uses a single seed (seed${=}42$); whether the RE reversal replicates across seeds and generalizes to other RE benchmarks warrants further investigation.\nThe non-tied subset ($n{=}210$) is partially reshuffled under free-form decoding: Jaccard similarity between the constrained and free-form non-tied sets is 0.472: 87 instances newly gain LP discrimination while others lose it, and the newly non-tied subset shows a $3{\\times}$ increase in within-instance LP range for the newly non-tied subset.\nDespite this reshuffling, aggregate NER selection gains remain negligible. Score compression is not a fixed property of specific instances but rather a pervasive regime that shifts across instances without producing net selection improvement.\nFree-form decoding also slightly improves quality estimation (NER VC $\\rho$: 0.379$\\to$0.409), though this does not translate to selection gains.\n\n\\section{Free-Form Decoding Ablation}\\label{app:freeform_ablation}\n\nTable~\\ref{tab:freeform_ablation} compares constrained and free-form decoding across four dimensions on SciERC ($N{=}8$, $T{=}1.0$, Qwen3-8B; seed${=}42$ shown, 4-seed RE statistics below).\nFree-form decoding removes grammar constraints entirely; outputs are parsed post-hoc (parse rate 99.95\\%, 4406/4408).\nLP score distributions are nearly identical across regimes (Panel~A: within-instance std ratio $0.97{\\times}$), and NER selection gains remain negligible under both regimes (Panel~B).\nRE LP selection consistently reverses direction under free-form decoding across 4 seeds: $+1.84{\\pm}0.12$~pp (seeds 42/123/456/789: $+1.69$, $+1.76$, $+2.00$, $+1.91$~pp) vs.\\ $-0.68$~pp constrained.\nThe constrained reference ($-0.68$~pp) uses the ablation-matched baseline; the primary experiment (Table~\\ref{tab:selection}) yields $-0.9$~pp on the same gold-filtered set.\nQuality estimation improves modestly for most signals under free-form decoding (Panel~C), with the largest gain for FK ($+0.053$ NER, $+0.039$ RE).\n\n\\begin{table*}[t]\n\\centering\n\\caption{Comparison of constrained vs.\\ free-form decoding on SciERC (Qwen3-8B, $N{=}8$, $T{=}1.0$, seed${=}42$; RE selection gap replicates across 4 seeds: $+1.84{\\pm}0.12$~pp).}\n\\label{tab:freeform_ablation}\n\n\\vspace{2pt}\n{\\small\\textsc{Panel A: Logprob Distribution}}\n\\vspace{2pt}\n\n\\begin{tabular}{lccc}\n\\toprule\nMetric & Constrained & Free-form & $\\Delta$ \\\\\n\\midrule\nMean LP std        & 0.0206 & 0.0199 & $-$0.0007 \\\\\nMean LP range      & 0.0623 & 0.0599 & $-$0.0024 \\\\\nTied fraction ($\\varepsilon{=}0.05$) & 59.7\\% & 57.7\\% & $-$2.0\\,pp \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{8pt}\n\n{\\small\\textsc{Panel B: Selection F1}}\n\\vspace{2pt}\n\n\\begin{tabular}{llccc}\n\\toprule\nTask & Method & Constrained & Free-form & $\\Delta$ \\\\\n\\midrule\n\\multirow{3}{*}{NER}\n  & Greedy        & 0.6182 & 0.6204 & $+$0.0022 \\\\\n  & LP-selected   & 0.6241 & 0.6222 & $-$0.0019 \\\\\n  & Selection gap & $+$0.0059 & $+$0.0018 & $-$0.0041 \\\\\n\\midrule\n\\multirow{3}{*}{RE}\n  & Greedy        & 0.2913 & 0.2880 & $-$0.0033 \\\\\n  & LP-selected   & 0.2845 & 0.3050 & \\textbf{$+$0.0205} \\\\\n  & Selection gap & $-$0.0068 & $+$0.0169 & \\textbf{$+$0.0237} \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{8pt}\n\n{\\small\\textsc{Panel C: QE Signal Quality (Spearman $\\rho$)}}\n\\vspace{2pt}\n\n\\begin{tabular}{l ccc ccc}\n\\toprule\n & \\multicolumn{3}{c}{NER ($n{=}529$)} & \\multicolumn{3}{c}{RE ($n{=}397$)} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\nSignal & Constr. & Free & $\\Delta$ & Constr. & Free & $\\Delta$ \\\\\n\\midrule\nSJ & 0.360 & 0.377 & $+$0.018 & 0.250 & 0.273 & $+$0.023 \\\\\nFK & 0.267 & 0.320 & $+$0.053 & 0.275 & 0.315 & $+$0.039 \\\\\nLP & 0.205 & 0.213 & $+$0.008 & 0.266 & 0.304 & $+$0.038 \\\\\nEM & 0.295 & 0.317 & $+$0.023 & 0.134 & 0.137 & $+$0.002 \\\\\nVC & 0.379 & 0.409 & $+$0.030 & 0.350 & 0.323 & $-$0.026 \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{8pt}\n\n{\\small\\textsc{Panel D: Parse Rate (Free-form)}}\n\\vspace{2pt}\n\n\\begin{tabular}{lc}\n\\toprule\nMetric & Value \\\\\n\\midrule\nTotal samples          & 4408 \\\\\nParse rate             & 99.95\\% \\\\\nInstances 8/8 valid    & 549\\,/\\,551 (99.6\\%) \\\\\n\\bottomrule\n\\end{tabular}\n\n\\end{table*}\n\n\\paragraph{CoNLL NER free-form results.}\nExtending the free-form ablation to CoNLL NER (Qwen3-8B, 4 seeds, $N{=}8$, $T{=}1.0$), LP range median is $0.058{\\pm}0.007$ across seeds, higher than SciERC ($0.041$) but still compressed given CoNLL's 86.8\\% tied fraction under constrained decoding.\nFree-form decoding reduces the tied fraction modestly, yet selection remains below single-sample: LP-selected F1${=}0.896$ vs.\\ single-sample $0.904$ ($\\Delta{=}{-}0.77$~pp).\nQuality estimation under free-form decoding yields SJ $\\rho{=}0.461$, EM $\\rho{=}0.471$, LP $\\rho{=}0.326$, comparable to constrained results (Table~\\ref{tab:quality_estimation}).\nThe failure to improve selection despite reduced compression is consistent with CoNLL's low oracle headroom (4.25~pp at $N{=}8$), which limits the selection space regardless of score distribution quality.\n\n\\section{LP Selection Failure Stability}\\label{app:lp_failure_stability}\n\nWe analyze RE LP selection failures across three random seeds (constrained decoding, $N{=}8$, $T{=}1.0$, Qwen3-8B) to assess whether failures are systematic or stochastic.\n\n\\paragraph{Pairwise overlap.}\nLP selection failures (instances where LP-selected F1 $<$ single-sample F1) show moderate cross-seed stability: the average pairwise Jaccard similarity is 0.42 (range: 0.38--0.46); failures are partially systematic (driven by instance complexity) but not fully deterministic.\nThe 3-way intersection contains 34 instances (27.9\\% of any-seed failures), which constitutes a stable failure core.\n\n\\paragraph{Instance complexity drives failure.}\nTable~\\ref{tab:stable_failures} stratifies instances by failure stability.\nStable failures (all 3 seeds) involve more gold relations (2.12 vs.\\ 1.62 for never-fail instances) and higher single-sample F1 (0.688 vs.\\ 0.429); LP mis-selects on instances where the model already performs well, precisely the instances where selection would be most valuable.\nFailure rate increases monotonically with gold relation count: 4.3\\% at 1 relation, 20.7\\% at 3 relations, 26.2\\% at 6 relations.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{RE LP selection failure stability across 3 seeds (SciERC, $N{=}8$). Stable failures concentrate on relation-dense instances with high single-sample F1.}\n\\label{tab:stable_failures}\n\\begin{tabular}{lcccc}\n\\toprule\nGroup & $n$ & Gold rels & Greedy F1 & LP $\\Delta$F1 \\\\\n\\midrule\nStable fail (3 seeds) & 34 & 2.12 & 0.688 & $-$0.499 \\\\\nFail 2+ seeds & 26 & 2.46 & 0.774 & $-$0.450 \\\\\nFail 1 seed & 62 & 2.32 & 0.692 & $-$0.239 \\\\\nNever fail & 429 & 1.62 & 0.429 & $+$0.041 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Flip instances.}\nOnly 5 RE instances with gold relations flip from LP failure (constrained) to LP success (free-form), with mean gold relation count 3.67 (well above the population mean of 1.86).\nThese instances show large constrained LP errors ($\\Delta{=}{-}0.430$) that reverse under free-form decoding ($\\Delta{=}{+}0.503$), but their rarity (5/397) confirms that the RE selection flip is driven by aggregate variance reallocation rather than systematic instance-level correction.\n\n\\section{$N$-Scaling Detailed Analysis}\\label{app:n_scaling}\n\nTables~\\ref{tab:n-scaling}--\\ref{tab:sigma-comparison} provide detailed $N$-scaling analysis on Qwen3-8B SciERC with 3-seed statistics.\n\n\\begin{table}[t]\n\\centering\n\\caption{Effect of sample pool size on signal quality (Qwen3-8B, SciERC, 3-seed mean Spearman $\\rho$).}\n\\label{tab:n-scaling}\n\\small",
      "numLines": 200,
      "startLine": 700,
      "totalLines": 1354
    }
  }
}
```

</details>

---

### Tool call

_source line 73_

<details open><summary>🔧 Tool call — Read · `toolu_013D1Shx7JSCUH4o127zs9Ji`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "offset": 900,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "e86cd1fe-b04a-41bd-a843-cc75390887c2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Km8vJfkVAPHe1cBD4XwKo5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7892,
      "cache_read_input_tokens": 61425,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7892
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

_source line 74 · 2026-05-18T05:47:07.058Z_

<details><summary>↩ Tool result · `toolu_013D1Shx7JSCUH4o127zs9Ji`</summary>

```text
900	\begin{tabular}{l ccc ccc}
901	\toprule
902	 & \multicolumn{3}{c}{\textbf{NER} $\rho$} & \multicolumn{3}{c}{\textbf{RE} $\rho$} \\
903	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
904	Signal & $N\!=\!8$ & $N\!=\!16$ & $\Delta$ & $N\!=\!8$ & $N\!=\!16$ & $\Delta$ \\
905	\midrule
906	SJ & 0.3641 & 0.4105 & \textbf{+0.0464} & 0.2485 & 0.2758 & \textbf{+0.0273} \\
907	FK & 0.2536 & 0.2833 & \textbf{+0.0297} & 0.2903 & 0.2964 & \textbf{+0.0061} \\
908	VC & 0.3861 & 0.4092 & \textbf{+0.0231} & 0.3088 & 0.3738 & \textbf{+0.0650} \\
909	LP & 0.2167 & 0.2393 & \textbf{+0.0226} & 0.2970 & 0.3100 & \textbf{+0.0130} \\
910	EM & 0.3071 & 0.3395 & \textbf{+0.0324} & 0.1353 & 0.1506 & \textbf{+0.0153} \\
911	\midrule
912	Mean & 0.3055 & 0.3364 & \textbf{+0.0308} & 0.2560 & 0.2813 & \textbf{+0.0253} \\
913	\bottomrule
914	\end{tabular}
915	\end{table}
916	
917	\begin{table}[t]
918	\centering
919	\caption{Cross-seed signal ranking stability (Kendall's $W$, 3 seeds).}
920	\label{tab:ranking-stability}
921	\small
922	\begin{tabular}{ll cc l}
923	\toprule
924	Model & Task & $N$ & Kendall's $W$ & Consensus ranking \\
925	\midrule
926	Qwen  & NER & 8  & 1.000 & VC $>$ SJ $>$ EM $>$ FK $>$ LP \\
927	Qwen  & NER & 16 & 0.956 & SJ $\approx$ VC $>$ EM $>$ FK $>$ LP \\
928	Qwen  & RE  & 8  & 0.822 & VC $>$ LP $>$ FK $>$ SJ $>$ EM \\
929	Qwen  & RE  & 16 & 0.956 & VC $>$ LP $>$ FK $>$ SJ $>$ EM \\
930	LLaMA & NER & 8  & 1.000 & VC $>$ SJ $>$ EM $>$ FK $>$ LP \\
931	\bottomrule
932	\end{tabular}
933	\end{table}
934	
935	\begin{table}[t]
936	\centering
937	\caption{Cross-seed standard deviation ($\sigma$) of Spearman $\rho$ at $N\!=\!8$ vs.\ $N\!=\!16$ (Qwen3-8B, SciERC, 3 seeds). $\sigma$ is population standard deviation.}
938	\label{tab:sigma-comparison}
939	\small
940	\begin{tabular}{l cc cc}
941	\toprule
942	 & \multicolumn{2}{c}{\textbf{NER} $\sigma_\rho$} & \multicolumn{2}{c}{\textbf{RE} $\sigma_\rho$} \\
943	\cmidrule(lr){2-3} \cmidrule(lr){4-5}
944	Signal & $N\!=\!8$ & $N\!=\!16$ & $N\!=\!8$ & $N\!=\!16$ \\
945	\midrule
946	SJ & 0.0179 & 0.0102 & 0.0015 & 0.0067 \\
947	FK & 0.0157 & 0.0079 & 0.0121 & 0.0143 \\
948	VC & 0.0187 & 0.0260 & 0.0244 & 0.0158 \\
949	EM & 0.0076 & 0.0031 & 0.0157 & 0.0049 \\
950	LP & 0.0125 & 0.0017 & 0.0218 & 0.0152 \\
951	\midrule
952	Mean & 0.0145 & 0.0098 & 0.0151 & 0.0114 \\
953	\bottomrule
954	\end{tabular}
955	\end{table}
956	
957	Signal rankings are consistent across our 3 seeds (Kendall's $W{=}1.000$ for NER at $N{=}8$, both models), dropping to $W{=}0.956$ at $N{=}16$ where SJ and VC converge (Table~\ref{tab:ranking-stability}); however, with only $n{=}3$ seeds statistical power is insufficient to confirm stability, and additional seeds may reveal ranking changes.
958	Doubling $N$ reduces cross-seed $\sigma$ by 32\% on NER and 24\% on RE (Table~\ref{tab:sigma-comparison}), with the largest reductions for SJ ($-43\%$ NER) and EM ($-59\%$ NER); additional samples stabilize structural signals more than LP.
959	
960	\paragraph{$N$-scaling: selection headroom vs.\ selection gain.}
961	Table~\ref{tab:n_scaling_selection} traces the effect of sample count on degeneracy, oracle headroom, and per-signal selection gain.
962	Oracle headroom grows roughly linearly with $N$ ($+4.4$~pp at $N{=}2$ to $+20.0$~pp at $N{=}32$).
963	LP selection improves monotonically with $N$ ($+0.39$~pp at $N{=}8$ to $+0.95$~pp at $N{=}32$), but even at $N{=}32$, where degeneracy falls to 4\% and oracle headroom reaches ${\sim}20$~pp, the best signal captures less than 5\% of the available improvement.
964	Degeneracy drops monotonically (43\% at $N{=}2$ to 4\% at $N{=}32$), yet reduced degeneracy does not unlock selection, consistent with the LoRA-rank ablation finding (\S\ref{sec:robustness_main}).
965	VC selection degrades with increasing $N$ ($-2.66$~pp at $N{=}2$ to $-4.35$~pp at $N{=}32$), consistent with mode-seeking bias in voting-based selection as the candidate pool grows.
966	
967	\begin{table}[t]
968	\centering
969	\small
970	\caption{Effect of sample count on selection (SciERC NER, Qwen3-8B, $T{=}1.0$, gold-filtered, seed${=}42$; exp\_025).\protect\footnotemark\ ``Best $\Delta$'': highest selection gain across all 5 signals. Per-signal $\Delta$ in pp vs.~greedy.}
971	\label{tab:n_scaling_selection}
972	\begin{tabular}{ccccccccc}
973	\toprule
974	$N$ & Degen.\% & Oracle (pp) & LP & SJ & FK & EM & VC & Best $\Delta$ \\
975	\midrule
976	2 & 42.7\% & $+$4.4 & $-$0.89 & $-$2.72 & $-$2.72 & $-$2.72 & $-$2.66 & $-$0.89 \\
977	4 & 21.0\% & $+$10.2 & $+$0.03 & $-$0.31 & $-$0.40 & $-$0.74 & $-$2.16 & $+$0.03 \\
978	8 & 11.0\% & $+$14.5 & $+$0.39 & $+$0.20 & $+$0.15 & $-$0.77 & $-$2.87 & $+$0.39 \\
979	16 & 7.4\% & $+$17.7 & $+$0.78 & $+$0.24 & $-$0.02 & $-$0.06 & $-$3.95 & $+$0.78 \\
980	32 & 4.0\% & $+$20.0 & $+$0.95 & $+$0.35 & $+$0.65 & $+$0.22 & $-$4.35 & $+$0.95 \\
981	\bottomrule
982	\end{tabular}
983	\end{table}
984	\footnotetext{$N$-scaling analysis uses gold-filtered evaluation ($n{=}529$, greedy F1${=}0.640$). Values differ slightly from Table~\ref{tab:selection} (0.645) and Table~\ref{tab:fewnerd} (0.644) due to seed and aggregation differences; relative trends are consistent.}
985	
986	\paragraph{Bootstrap significance at $N{=}32$.}
987	Table~\ref{tab:bootstrap_n32} reports bootstrap confidence intervals and $p$-values for selection at $N{=}32$ ($B{=}10{,}000$, $n{=}529$).
988	No signal achieves significant improvement over greedy at $\alpha{=}0.05$ (LP: $p{=}0.091$; FK: $p{=}0.101$), while VC is significantly \textit{worse} ($-4.36$~pp, $p{=}1.0$).
989	However, all signals except VC significantly outperform random selection ($p{<}0.001$, permutation test); the signals carry meaningful quality information yet fail to translate it into reliable selection gains.
990	The oracle gap ($+20.0$~pp, $p{<}0.001$) confirms substantial unrealized headroom.
991	
992	\begin{table}[t]
993	\centering
994	\small
995	\caption{Bootstrap significance test at $N{=}32$ (SciERC NER, Qwen3-8B, $T{=}1.0$, $B{=}10{,}000$, $n{=}529$ gold-non-empty instances; 22 instances with no gold entities are excluded as they contribute zero selection differential). $\Delta$: selection gain vs.\ greedy. CI: 95\% bootstrap percentile interval. $p_{\text{greedy}}$: one-sided $p$-value vs.\ greedy; $p_{\text{rand}}$: permutation test vs.\ random selection.}
996	\label{tab:bootstrap_n32}
997	\begin{tabular}{lcccc}
998	\toprule
999	Signal & $\Delta$ (pp) & 95\% CI & $p_{\text{greedy}}$ & $p_{\text{rand}}$ \\
1000	\midrule
1001	LP & $+$0.95 & [$-$0.41, $+$2.34] & 0.091 & ${<}$0.001 \\
1002	FK & $+$0.66 & [$-$0.36, $+$1.67] & 0.101 & ${<}$0.001 \\
1003	SJ & $+$0.36 & [$-$0.66, $+$1.38] & 0.244 & ${<}$0.001 \\
1004	EM & $+$0.22 & [$-$0.99, $+$1.44] & 0.355 & ${<}$0.001 \\
1005	VC & $-$4.36 & [$-$6.26, $-$2.37] & 1.000 & 0.741 \\
1006	\midrule
1007	Oracle & $+$20.00 & [$+$17.98, $+$22.10] & ${<}$0.001 & --- \\
1008	\bottomrule
1009	\end{tabular}
1010	\end{table}
1011	
1012	\section{Temperature Ablation}\label{app:t_ablation}
1013	
1014	Table~\ref{tab:t_ablation} reports the effect of sampling temperature on QE signals, oracle headroom, and output quality across four temperatures on SciERC NER.
1015	
1016	\begin{table}[t]
1017	\centering
1018	\small
1019	\caption{Temperature ablation on SciERC NER (Qwen3-8B, $N{=}8$, seed${=}42$). Oracle gap and QE $\rho$ across four temperatures. $\kappa$: Fleiss' $\kappa$ (inter-sample agreement). $T{=}0.5$ and $T{=}1.0$ use joint (NER+RE) subtask; $T{=}0.8$ and $T{=}1.2$ use NER-only.}
1020	\label{tab:t_ablation}
1021	\begin{tabular}{ccccccc}
1022	\toprule
1023	$T$ & Oracle gap (pp) & SJ $\rho$ & LP $\rho$ & $\kappa$ & Sample F1 \\
1024	\midrule
1025	0.5 & $+$7.8 & 0.297 & 0.218 & 0.577 & 0.636 \\
1026	0.8 & $+$10.5 & 0.359 & 0.253 & 0.451 & 0.622 \\
1027	1.0 & $+$13.3 & 0.360 & 0.205 & ${\approx}$0.39 & ${\approx}$0.612 \\
1028	1.2 & $+$13.0 & 0.377 & 0.196 & 0.356 & 0.594 \\
1029	\bottomrule
1030	\end{tabular}
1031	\end{table}
1032	
1033	Oracle headroom increases monotonically with temperature ($+7.8$~pp at $T{=}0.5$ to $+13.3$~pp at $T{=}1.0$), plateauing at $T{=}1.2$ ($+13.0$~pp); the plateau suggests $T{=}1.0$ already approaches the diversity ceiling for constrained structured decoding.
1034	Structural QE signals improve with temperature: SJ $\rho$ rises from $0.297$ ($T{=}0.5$) to $0.377$ ($T{=}1.2$), consistent with more diverse outputs providing richer pairwise evidence.
1035	LP $\rho$ peaks at $T{=}0.8$ ($0.253$) then degrades to $0.196$ at $T{=}1.2$.
1036	This divergence confirms that LP compression is model-intrinsic: higher temperature increases between-instance LP variance (benefiting structural signals) but does not resolve within-instance compression, degrading LP's discriminative power.
1037	Inter-sample agreement ($\kappa$) decreases monotonically ($0.577$ to $0.356$); higher temperature generates more diverse outputs. Mean sample F1 also decreases ($0.636$ to $0.594$), consistent with the quality--diversity trade-off.
1038	The $T{=}0.7$ and $T{=}1.0$ comparison in Table~\ref{tab:robustness} is consistent with the trends reported here.
1039	
1040	\paragraph{Temperature controls degeneracy and LP spread.}
1041	Table~\ref{tab:t_degeneracy} reports instance degeneracy (constant F1, gold-filtered) and median within-instance LP range across four temperatures on SciERC.
1042	Both quantities are strictly monotonic in $T$: degeneracy falls from 40.3\% ($T{=}0.5$) to 12.5\% ($T{=}1.2$), while LP range increases from 0.015 to 0.058 nats.
1043	Temperature thus provides a direct lever for practitioners to shift the degeneracy regime.
1044	However, even at $T{=}1.2$ where degeneracy (12.5\%) approaches Few-NERD levels (13.8\%), within-instance $\rho(\text{LP}, \text{F1})$ remains at 0.225, far below Few-NERD's ${\sim}$0.5.
1045	This confirms that temperature controls degeneracy (the first necessary condition) but cannot improve LP-quality alignment (the second condition), which is largely determined by task structure and remains relatively stable across generation configurations (\S\ref{app:epoch_confound}); the two conditions are jointly necessary and independently variable.
1046	
1047	\begin{table}[h]
1048	\centering
1049	\small
1050	\caption{Temperature sensitivity of degeneracy and LP spread (SciERC NER, Qwen3-8B, $N{=}8$). Degeneracy: constant-F1, gold-filtered. LP range: median within-instance range.}
1051	\label{tab:t_degeneracy}
1052	\begin{tabular}{ccccc}
1053	\toprule
1054	$T$ & Degen.\% & LP range (nats) & Fleiss' $\kappa$ & SJ mean \\
1055	\midrule
1056	0.5 & 40.3 & 0.015 & 0.572 & 0.830 \\
1057	0.8 & 27.2 & 0.031 & 0.471 & 0.752 \\
1058	1.0 & 17.8 & 0.042 & 0.405 & 0.700 \\
1059	1.2 & 12.5 & 0.058 & 0.352 & 0.647 \\
1060	\bottomrule
1061	\end{tabular}
1062	\end{table}
1063	
1064	\section{Cross-Dataset OOD Analysis}\label{app:ood}
1065	
1066	To test whether confidence signals generalize under domain shift, we evaluate models on out-of-distribution data: a SciERC-trained model applied to CoNLL instances (wider$\to$narrower schema) and vice versa (Table~\ref{tab:ood}).
1067	
1068	\begin{table}[t]
1069	\centering
1070	\small
1071	\caption{Cross-dataset OOD quality estimation (Spearman $\rho$, Qwen3-8B, $N{=}8$, $T{=}1.0$, seed${=}42$). SciERC$\to$CoNLL: SciERC-trained model on CoNLL instances ($n{=}2756$). CoNLL$\to$SciERC: CoNLL-trained model on SciERC instances ($n{=}529$, excluded from conclusions due to catastrophic model failure). In-domain $\rho$ from Table~\ref{tab:quality_estimation} (same model, same seed). \textsuperscript{***}$p{<}0.001$, \textsuperscript{*}$p{<}0.05$.}
1072	\label{tab:ood}
1073	\begin{tabular}{l ccc ccc}
1074	\toprule
1075	 & \multicolumn{3}{c}{\textbf{SciERC$\to$CoNLL}} & \multicolumn{3}{c}{\textbf{CoNLL$\to$SciERC}} \\
1076	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
1077	Signal & $\rho$ & In-dom. & $\Delta$ & $\rho$ & In-dom. & $\Delta$ \\
1078	\midrule
1079	VC & .469\textsuperscript{***} & .379 & +.090 & +.105\textsuperscript{*} & .379 & $-$.274 \\
1080	SJ & .378\textsuperscript{***} & .360 & +.018 & $-$.186\textsuperscript{***} & .360 & $-$.546 \\
1081	EM & .300\textsuperscript{***} & .295 & +.005 & $-$.202\textsuperscript{***} & .295 & $-$.497 \\
1082	FK & .285\textsuperscript{***} & .267 & +.018 & $-$.070 & .267 & $-$.337 \\
1083	LP & .246\textsuperscript{***} & .205 & +.041 & $-$.152\textsuperscript{***} & .205 & $-$.357 \\
1084	\bottomrule
1085	\end{tabular}
1086	\end{table}
1087	
1088	\paragraph{Wider-to-narrower schema transfer.}
1089	When the SciERC-trained model (6 NER types) is applied to CoNLL (4 types), all signals remain significant ($p{<}0.001$) and structural signals improve over their in-domain levels (same model, seed${=}42$, $N{=}8$; in-domain $\rho$ from Table~\ref{tab:quality_estimation}): VC reaches $\rho{=}0.469$ (in-domain $0.379$, $\Delta{=}{+}0.090$), SJ $\rho{=}0.378$ (in-domain $0.360$, $\Delta{=}{+}0.018$), and FK $\rho{=}0.285$ (in-domain $0.267$, $\Delta{=}{+}0.018$).
1090	The wider training schema subsumes CoNLL's narrower schema, so the model produces reasonable outputs even out-of-domain (single-sample F1${=}0.522$), and structural signals benefit from the simpler target schema's reduced output ambiguity.
1091	
1092	\paragraph{Narrower-to-wider schema transfer (excluded).}
1093	The reverse direction is excluded from our conclusions due to catastrophic model failure, not signal failure.
1094	The CoNLL-trained model recognizes only 4 news entity types (PER, ORG, LOC, MISC) and has no relation extraction capability; when applied to SciERC's 6 scientific entity types and 7 relation types, the model cannot produce meaningful structured outputs (single-sample NER F1${=}0.009$, RE F1${=}0.001$).
1095	Under this regime, most signals flip to negative or near-zero correlations (Table~\ref{tab:ood}); only VC retains weak positive correlation ($\rho{=}0.105$, $p{=}0.016$).
1096	These negative correlations reflect the model systematically generating confident but incorrect outputs, a capability failure analogous to WNUT-17 (\S\ref{sec:qe_results}) and not evidence against signal utility.
1097	
1098	\paragraph{Asymmetry interpretation.}
1099	The directional asymmetry is driven by schema coverage: wider$\to$narrower preserves signal utility because the SciERC model's 6-type schema subsumes CoNLL's 4 types, while narrower$\to$wider fails because the CoNLL model lacks the entity and relation types required by SciERC.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "94186e16-ae59-4a29-a3a7-86c0ff53f778",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "\\begin{tabular}{l ccc ccc}\n\\toprule\n & \\multicolumn{3}{c}{\\textbf{NER} $\\rho$} & \\multicolumn{3}{c}{\\textbf{RE} $\\rho$} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\nSignal & $N\\!=\\!8$ & $N\\!=\\!16$ & $\\Delta$ & $N\\!=\\!8$ & $N\\!=\\!16$ & $\\Delta$ \\\\\n\\midrule\nSJ & 0.3641 & 0.4105 & \\textbf{+0.0464} & 0.2485 & 0.2758 & \\textbf{+0.0273} \\\\\nFK & 0.2536 & 0.2833 & \\textbf{+0.0297} & 0.2903 & 0.2964 & \\textbf{+0.0061} \\\\\nVC & 0.3861 & 0.4092 & \\textbf{+0.0231} & 0.3088 & 0.3738 & \\textbf{+0.0650} \\\\\nLP & 0.2167 & 0.2393 & \\textbf{+0.0226} & 0.2970 & 0.3100 & \\textbf{+0.0130} \\\\\nEM & 0.3071 & 0.3395 & \\textbf{+0.0324} & 0.1353 & 0.1506 & \\textbf{+0.0153} \\\\\n\\midrule\nMean & 0.3055 & 0.3364 & \\textbf{+0.0308} & 0.2560 & 0.2813 & \\textbf{+0.0253} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-seed signal ranking stability (Kendall's $W$, 3 seeds).}\n\\label{tab:ranking-stability}\n\\small\n\\begin{tabular}{ll cc l}\n\\toprule\nModel & Task & $N$ & Kendall's $W$ & Consensus ranking \\\\\n\\midrule\nQwen  & NER & 8  & 1.000 & VC $>$ SJ $>$ EM $>$ FK $>$ LP \\\\\nQwen  & NER & 16 & 0.956 & SJ $\\approx$ VC $>$ EM $>$ FK $>$ LP \\\\\nQwen  & RE  & 8  & 0.822 & VC $>$ LP $>$ FK $>$ SJ $>$ EM \\\\\nQwen  & RE  & 16 & 0.956 & VC $>$ LP $>$ FK $>$ SJ $>$ EM \\\\\nLLaMA & NER & 8  & 1.000 & VC $>$ SJ $>$ EM $>$ FK $>$ LP \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-seed standard deviation ($\\sigma$) of Spearman $\\rho$ at $N\\!=\\!8$ vs.\\ $N\\!=\\!16$ (Qwen3-8B, SciERC, 3 seeds). $\\sigma$ is population standard deviation.}\n\\label{tab:sigma-comparison}\n\\small\n\\begin{tabular}{l cc cc}\n\\toprule\n & \\multicolumn{2}{c}{\\textbf{NER} $\\sigma_\\rho$} & \\multicolumn{2}{c}{\\textbf{RE} $\\sigma_\\rho$} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nSignal & $N\\!=\\!8$ & $N\\!=\\!16$ & $N\\!=\\!8$ & $N\\!=\\!16$ \\\\\n\\midrule\nSJ & 0.0179 & 0.0102 & 0.0015 & 0.0067 \\\\\nFK & 0.0157 & 0.0079 & 0.0121 & 0.0143 \\\\\nVC & 0.0187 & 0.0260 & 0.0244 & 0.0158 \\\\\nEM & 0.0076 & 0.0031 & 0.0157 & 0.0049 \\\\\nLP & 0.0125 & 0.0017 & 0.0218 & 0.0152 \\\\\n\\midrule\nMean & 0.0145 & 0.0098 & 0.0151 & 0.0114 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nSignal rankings are consistent across our 3 seeds (Kendall's $W{=}1.000$ for NER at $N{=}8$, both models), dropping to $W{=}0.956$ at $N{=}16$ where SJ and VC converge (Table~\\ref{tab:ranking-stability}); however, with only $n{=}3$ seeds statistical power is insufficient to confirm stability, and additional seeds may reveal ranking changes.\nDoubling $N$ reduces cross-seed $\\sigma$ by 32\\% on NER and 24\\% on RE (Table~\\ref{tab:sigma-comparison}), with the largest reductions for SJ ($-43\\%$ NER) and EM ($-59\\%$ NER); additional samples stabilize structural signals more than LP.\n\n\\paragraph{$N$-scaling: selection headroom vs.\\ selection gain.}\nTable~\\ref{tab:n_scaling_selection} traces the effect of sample count on degeneracy, oracle headroom, and per-signal selection gain.\nOracle headroom grows roughly linearly with $N$ ($+4.4$~pp at $N{=}2$ to $+20.0$~pp at $N{=}32$).\nLP selection improves monotonically with $N$ ($+0.39$~pp at $N{=}8$ to $+0.95$~pp at $N{=}32$), but even at $N{=}32$, where degeneracy falls to 4\\% and oracle headroom reaches ${\\sim}20$~pp, the best signal captures less than 5\\% of the available improvement.\nDegeneracy drops monotonically (43\\% at $N{=}2$ to 4\\% at $N{=}32$), yet reduced degeneracy does not unlock selection, consistent with the LoRA-rank ablation finding (\\S\\ref{sec:robustness_main}).\nVC selection degrades with increasing $N$ ($-2.66$~pp at $N{=}2$ to $-4.35$~pp at $N{=}32$), consistent with mode-seeking bias in voting-based selection as the candidate pool grows.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Effect of sample count on selection (SciERC NER, Qwen3-8B, $T{=}1.0$, gold-filtered, seed${=}42$; exp\\_025).\\protect\\footnotemark\\ ``Best $\\Delta$'': highest selection gain across all 5 signals. Per-signal $\\Delta$ in pp vs.~greedy.}\n\\label{tab:n_scaling_selection}\n\\begin{tabular}{ccccccccc}\n\\toprule\n$N$ & Degen.\\% & Oracle (pp) & LP & SJ & FK & EM & VC & Best $\\Delta$ \\\\\n\\midrule\n2 & 42.7\\% & $+$4.4 & $-$0.89 & $-$2.72 & $-$2.72 & $-$2.72 & $-$2.66 & $-$0.89 \\\\\n4 & 21.0\\% & $+$10.2 & $+$0.03 & $-$0.31 & $-$0.40 & $-$0.74 & $-$2.16 & $+$0.03 \\\\\n8 & 11.0\\% & $+$14.5 & $+$0.39 & $+$0.20 & $+$0.15 & $-$0.77 & $-$2.87 & $+$0.39 \\\\\n16 & 7.4\\% & $+$17.7 & $+$0.78 & $+$0.24 & $-$0.02 & $-$0.06 & $-$3.95 & $+$0.78 \\\\\n32 & 4.0\\% & $+$20.0 & $+$0.95 & $+$0.35 & $+$0.65 & $+$0.22 & $-$4.35 & $+$0.95 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\\footnotetext{$N$-scaling analysis uses gold-filtered evaluation ($n{=}529$, greedy F1${=}0.640$). Values differ slightly from Table~\\ref{tab:selection} (0.645) and Table~\\ref{tab:fewnerd} (0.644) due to seed and aggregation differences; relative trends are consistent.}\n\n\\paragraph{Bootstrap significance at $N{=}32$.}\nTable~\\ref{tab:bootstrap_n32} reports bootstrap confidence intervals and $p$-values for selection at $N{=}32$ ($B{=}10{,}000$, $n{=}529$).\nNo signal achieves significant improvement over greedy at $\\alpha{=}0.05$ (LP: $p{=}0.091$; FK: $p{=}0.101$), while VC is significantly \\textit{worse} ($-4.36$~pp, $p{=}1.0$).\nHowever, all signals except VC significantly outperform random selection ($p{<}0.001$, permutation test); the signals carry meaningful quality information yet fail to translate it into reliable selection gains.\nThe oracle gap ($+20.0$~pp, $p{<}0.001$) confirms substantial unrealized headroom.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Bootstrap significance test at $N{=}32$ (SciERC NER, Qwen3-8B, $T{=}1.0$, $B{=}10{,}000$, $n{=}529$ gold-non-empty instances; 22 instances with no gold entities are excluded as they contribute zero selection differential). $\\Delta$: selection gain vs.\\ greedy. CI: 95\\% bootstrap percentile interval. $p_{\\text{greedy}}$: one-sided $p$-value vs.\\ greedy; $p_{\\text{rand}}$: permutation test vs.\\ random selection.}\n\\label{tab:bootstrap_n32}\n\\begin{tabular}{lcccc}\n\\toprule\nSignal & $\\Delta$ (pp) & 95\\% CI & $p_{\\text{greedy}}$ & $p_{\\text{rand}}$ \\\\\n\\midrule\nLP & $+$0.95 & [$-$0.41, $+$2.34] & 0.091 & ${<}$0.001 \\\\\nFK & $+$0.66 & [$-$0.36, $+$1.67] & 0.101 & ${<}$0.001 \\\\\nSJ & $+$0.36 & [$-$0.66, $+$1.38] & 0.244 & ${<}$0.001 \\\\\nEM & $+$0.22 & [$-$0.99, $+$1.44] & 0.355 & ${<}$0.001 \\\\\nVC & $-$4.36 & [$-$6.26, $-$2.37] & 1.000 & 0.741 \\\\\n\\midrule\nOracle & $+$20.00 & [$+$17.98, $+$22.10] & ${<}$0.001 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Temperature Ablation}\\label{app:t_ablation}\n\nTable~\\ref{tab:t_ablation} reports the effect of sampling temperature on QE signals, oracle headroom, and output quality across four temperatures on SciERC NER.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Temperature ablation on SciERC NER (Qwen3-8B, $N{=}8$, seed${=}42$). Oracle gap and QE $\\rho$ across four temperatures. $\\kappa$: Fleiss' $\\kappa$ (inter-sample agreement). $T{=}0.5$ and $T{=}1.0$ use joint (NER+RE) subtask; $T{=}0.8$ and $T{=}1.2$ use NER-only.}\n\\label{tab:t_ablation}\n\\begin{tabular}{ccccccc}\n\\toprule\n$T$ & Oracle gap (pp) & SJ $\\rho$ & LP $\\rho$ & $\\kappa$ & Sample F1 \\\\\n\\midrule\n0.5 & $+$7.8 & 0.297 & 0.218 & 0.577 & 0.636 \\\\\n0.8 & $+$10.5 & 0.359 & 0.253 & 0.451 & 0.622 \\\\\n1.0 & $+$13.3 & 0.360 & 0.205 & ${\\approx}$0.39 & ${\\approx}$0.612 \\\\\n1.2 & $+$13.0 & 0.377 & 0.196 & 0.356 & 0.594 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOracle headroom increases monotonically with temperature ($+7.8$~pp at $T{=}0.5$ to $+13.3$~pp at $T{=}1.0$), plateauing at $T{=}1.2$ ($+13.0$~pp); the plateau suggests $T{=}1.0$ already approaches the diversity ceiling for constrained structured decoding.\nStructural QE signals improve with temperature: SJ $\\rho$ rises from $0.297$ ($T{=}0.5$) to $0.377$ ($T{=}1.2$), consistent with more diverse outputs providing richer pairwise evidence.\nLP $\\rho$ peaks at $T{=}0.8$ ($0.253$) then degrades to $0.196$ at $T{=}1.2$.\nThis divergence confirms that LP compression is model-intrinsic: higher temperature increases between-instance LP variance (benefiting structural signals) but does not resolve within-instance compression, degrading LP's discriminative power.\nInter-sample agreement ($\\kappa$) decreases monotonically ($0.577$ to $0.356$); higher temperature generates more diverse outputs. Mean sample F1 also decreases ($0.636$ to $0.594$), consistent with the quality--diversity trade-off.\nThe $T{=}0.7$ and $T{=}1.0$ comparison in Table~\\ref{tab:robustness} is consistent with the trends reported here.\n\n\\paragraph{Temperature controls degeneracy and LP spread.}\nTable~\\ref{tab:t_degeneracy} reports instance degeneracy (constant F1, gold-filtered) and median within-instance LP range across four temperatures on SciERC.\nBoth quantities are strictly monotonic in $T$: degeneracy falls from 40.3\\% ($T{=}0.5$) to 12.5\\% ($T{=}1.2$), while LP range increases from 0.015 to 0.058 nats.\nTemperature thus provides a direct lever for practitioners to shift the degeneracy regime.\nHowever, even at $T{=}1.2$ where degeneracy (12.5\\%) approaches Few-NERD levels (13.8\\%), within-instance $\\rho(\\text{LP}, \\text{F1})$ remains at 0.225, far below Few-NERD's ${\\sim}$0.5.\nThis confirms that temperature controls degeneracy (the first necessary condition) but cannot improve LP-quality alignment (the second condition), which is largely determined by task structure and remains relatively stable across generation configurations (\\S\\ref{app:epoch_confound}); the two conditions are jointly necessary and independently variable.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Temperature sensitivity of degeneracy and LP spread (SciERC NER, Qwen3-8B, $N{=}8$). Degeneracy: constant-F1, gold-filtered. LP range: median within-instance range.}\n\\label{tab:t_degeneracy}\n\\begin{tabular}{ccccc}\n\\toprule\n$T$ & Degen.\\% & LP range (nats) & Fleiss' $\\kappa$ & SJ mean \\\\\n\\midrule\n0.5 & 40.3 & 0.015 & 0.572 & 0.830 \\\\\n0.8 & 27.2 & 0.031 & 0.471 & 0.752 \\\\\n1.0 & 17.8 & 0.042 & 0.405 & 0.700 \\\\\n1.2 & 12.5 & 0.058 & 0.352 & 0.647 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Cross-Dataset OOD Analysis}\\label{app:ood}\n\nTo test whether confidence signals generalize under domain shift, we evaluate models on out-of-distribution data: a SciERC-trained model applied to CoNLL instances (wider$\\to$narrower schema) and vice versa (Table~\\ref{tab:ood}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-dataset OOD quality estimation (Spearman $\\rho$, Qwen3-8B, $N{=}8$, $T{=}1.0$, seed${=}42$). SciERC$\\to$CoNLL: SciERC-trained model on CoNLL instances ($n{=}2756$). CoNLL$\\to$SciERC: CoNLL-trained model on SciERC instances ($n{=}529$, excluded from conclusions due to catastrophic model failure). In-domain $\\rho$ from Table~\\ref{tab:quality_estimation} (same model, same seed). \\textsuperscript{***}$p{<}0.001$, \\textsuperscript{*}$p{<}0.05$.}\n\\label{tab:ood}\n\\begin{tabular}{l ccc ccc}\n\\toprule\n & \\multicolumn{3}{c}{\\textbf{SciERC$\\to$CoNLL}} & \\multicolumn{3}{c}{\\textbf{CoNLL$\\to$SciERC}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\nSignal & $\\rho$ & In-dom. & $\\Delta$ & $\\rho$ & In-dom. & $\\Delta$ \\\\\n\\midrule\nVC & .469\\textsuperscript{***} & .379 & +.090 & +.105\\textsuperscript{*} & .379 & $-$.274 \\\\\nSJ & .378\\textsuperscript{***} & .360 & +.018 & $-$.186\\textsuperscript{***} & .360 & $-$.546 \\\\\nEM & .300\\textsuperscript{***} & .295 & +.005 & $-$.202\\textsuperscript{***} & .295 & $-$.497 \\\\\nFK & .285\\textsuperscript{***} & .267 & +.018 & $-$.070 & .267 & $-$.337 \\\\\nLP & .246\\textsuperscript{***} & .205 & +.041 & $-$.152\\textsuperscript{***} & .205 & $-$.357 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Wider-to-narrower schema transfer.}\nWhen the SciERC-trained model (6 NER types) is applied to CoNLL (4 types), all signals remain significant ($p{<}0.001$) and structural signals improve over their in-domain levels (same model, seed${=}42$, $N{=}8$; in-domain $\\rho$ from Table~\\ref{tab:quality_estimation}): VC reaches $\\rho{=}0.469$ (in-domain $0.379$, $\\Delta{=}{+}0.090$), SJ $\\rho{=}0.378$ (in-domain $0.360$, $\\Delta{=}{+}0.018$), and FK $\\rho{=}0.285$ (in-domain $0.267$, $\\Delta{=}{+}0.018$).\nThe wider training schema subsumes CoNLL's narrower schema, so the model produces reasonable outputs even out-of-domain (single-sample F1${=}0.522$), and structural signals benefit from the simpler target schema's reduced output ambiguity.\n\n\\paragraph{Narrower-to-wider schema transfer (excluded).}\nThe reverse direction is excluded from our conclusions due to catastrophic model failure, not signal failure.\nThe CoNLL-trained model recognizes only 4 news entity types (PER, ORG, LOC, MISC) and has no relation extraction capability; when applied to SciERC's 6 scientific entity types and 7 relation types, the model cannot produce meaningful structured outputs (single-sample NER F1${=}0.009$, RE F1${=}0.001$).\nUnder this regime, most signals flip to negative or near-zero correlations (Table~\\ref{tab:ood}); only VC retains weak positive correlation ($\\rho{=}0.105$, $p{=}0.016$).\nThese negative correlations reflect the model systematically generating confident but incorrect outputs, a capability failure analogous to WNUT-17 (\\S\\ref{sec:qe_results}) and not evidence against signal utility.\n\n\\paragraph{Asymmetry interpretation.}\nThe directional asymmetry is driven by schema coverage: wider$\\to$narrower preserves signal utility because the SciERC model's 6-type schema subsumes CoNLL's 4 types, while narrower$\\to$wider fails because the CoNLL model lacks the entity and relation types required by SciERC.",
      "numLines": 200,
      "startLine": 900,
      "totalLines": 1354
    }
  }
}
```

</details>

---

### Tool call

_source line 75_

<details open><summary>🔧 Tool call — Read · `toolu_01SebaJfD6goYGfqH2qNwLDy`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "offset": 1100,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "f09ecde9-612b-4ebb-8bef-8acaf05be91d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Km8vJfkVAPHe1cBD4XwKo5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7892,
      "cache_read_input_tokens": 61425,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7892
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

_source line 76 · 2026-05-18T05:47:07.465Z_

<details><summary>↩ Tool result · `toolu_01SebaJfD6goYGfqH2qNwLDy`</summary>

```text
1100	This extends the capability boundary identified on WNUT-17 to the domain-shift setting: confidence signals require sufficient model capability as a prerequisite, and results from the CoNLL$\to$SciERC direction should not be interpreted as evidence of signal degradation under domain shift.
1101	
1102	\section{Verbalized Confidence}\label{app:verbalized_confidence}
1103	
1104	We evaluate verbalized confidence (VerbConf) as a second per-sample signal following \citet{tian2023calibration}: after generating each structured output, the model is prompted to rate its confidence on a 1--10 scale.
1105	Table~\ref{tab:verbconf} reports quality estimation and selection results.
1106	
1107	\begin{table}[t]
1108	\centering
1109	\small
1110	\caption{Verbalized confidence (VerbConf) vs.\ log-probability selection (Qwen3-8B, $N{=}8$, $T{=}1.0$, seed${=}42$). Parse fail: fraction of samples where the confidence score could not be extracted.}
1111	\label{tab:verbconf}
1112	\begin{tabular}{l cc cc}
1113	\toprule
1114	 & \multicolumn{2}{c}{\textbf{SciERC NER}} & \multicolumn{2}{c}{\textbf{CoNLL NER}} \\
1115	\cmidrule(lr){2-3} \cmidrule(lr){4-5}
1116	Metric & VerbConf & LP & VerbConf & LP \\
1117	\midrule
1118	$\rho$ & 0.297 & 0.205 & 0.337 & 0.316 \\
1119	AUROC & 0.681 & 0.578 & 0.747 & 0.753 \\
1120	Selection F1 & 0.620 & 0.647 & 0.889 & 0.904 \\
1121	$\Delta$ vs.\ greedy & $-$2.45\,pp & $+$0.2\,pp & $-$1.93\,pp & $-$0.77\,pp \\
1122	\midrule
1123	Mean score & 8.58\,/\,10 & --- & 9.24\,/\,10 & --- \\
1124	Parse fail rate & 0.26\% & --- & 0\% & --- \\
1125	\bottomrule
1126	\end{tabular}
1127	\end{table}
1128	
1129	\paragraph{Severe overconfidence.}
1130	VerbConf exhibits extreme score compression: mean confidence is 8.58/10 on SciERC (single-sample F1${=}0.645$) and 9.24/10 on CoNLL (single-sample F1${=}0.904$), with most scores concentrated in the 8--10 range.
1131	This compression is more severe than LP (which spans a 0.041-nat median range); score compression is a general property of model self-assessment, not an artifact of log-probability computation.
1132	
1133	\paragraph{QE--selection decoupling.}
1134	VerbConf achieves higher $\rho$ than LP on both datasets (SciERC: 0.297 vs.\ 0.205; CoNLL: 0.337 vs.\ 0.316) and competitive AUROC (SciERC: 0.681 vs.\ 0.578; CoNLL: 0.747 vs.\ 0.753), yet yields the worst selection among all signals ($\Delta{=}{-}2.45$~pp on SciERC, $-1.93$~pp on CoNLL).
1135	This dissociation further demonstrates the correlation-selection gap: a signal can rank instances by expected quality without being able to discriminate candidates within an instance.
1136	The AUROC--$\rho$ decoupling on CoNLL (LP leads AUROC at 0.753 while VerbConf leads $\rho$ at 0.337) reflects differing sensitivity to binary vs.\ ordinal discrimination.
1137	
1138	\section{LLaMA-3.2-3B Scale Ablation}\label{app:llama3b}
1139	
1140	To extend scale coverage below 4B, we fine-tune LLaMA-3.2-3B-Instruct on SciERC NER under identical training conditions (LoRA rank${=}32$, $\alpha{=}64$, 5 epochs) and evaluate quality estimation and selection (Table~\ref{tab:llama3b}).
1141	
1142	\begin{table}[t]
1143	\centering
1144	\small
1145	\caption{LLaMA-3.2-3B SciERC NER quality estimation and selection ($N{=}8$, $T{=}1.0$, seed${=}42$). Greedy F1${=}0.627$, Oracle F1${=}0.763$, headroom${=}13.63$~pp.}
1146	\label{tab:llama3b}
1147	\begin{tabular}{l cc cc}
1148	\toprule
1149	Signal & $\rho$ & AUROC & Sel.\ F1 & $\Delta$ vs.\ greedy \\
1150	\midrule
1151	VC & \textbf{.460} & .743 & 0.611 & $-$1.54\,pp \\
1152	SJ & .375 & .738 & \textbf{0.633} & $+$0.61\,pp \\
1153	EM & .334 & \textbf{.776} & --- & --- \\
1154	FK & .268 & .671 & 0.630 & $+$0.28\,pp \\
1155	LP & .266 & .633 & 0.628 & $+$0.12\,pp \\
1156	\midrule
1157	Greedy & --- & --- & 0.627 & --- \\
1158	Oracle & --- & --- & 0.763 & --- \\
1159	\bottomrule
1160	\end{tabular}
1161	\end{table}
1162	
1163	The $\rho$ ranking at 3B (VC $>$ SJ $>$ EM $>$ FK $\approx$ LP) preserves the structural-over-LP ordering from 8B (Table~\ref{tab:quality_estimation}); ranking stability holds across two model families spanning 3B--8B.
1164	AUROC rankings differ (EM $>$ VC $>$ SJ $>$ FK $>$ LP), consistent with the $\rho$--AUROC dissociation noted in the main text.
1165	Despite 13.63~pp of oracle headroom, no signal achieves significant selection improvement (best: SJ, $+0.61$~pp, $p{=}0.175$); VC, the strongest QE signal, yields the worst selection ($-1.54$~pp), consistent with the correlation-selection gap observed at larger scales.
1166	
1167	\section{Few-NERD Full Results}\label{app:fewnerd}
1168	
1169	Table~\ref{tab:fewnerd_full} reports the complete Few-NERD INTRA coarse evaluation (Qwen3-8B, LoRA rank${=}32$, 3 epochs, $N{=}8$, $T{=}1.0$).
1170	After gold-filtering (removing instances with no gold entities), the evaluation set contains $n{=}32{,}565$ instances across 8 coarse entity types; 11.9\% receive zero F1 under greedy decoding.
1171	Instance degeneracy is 13.8\% (vs.\ 17.8\% on SciERC, 59.1\% on CoNLL).
1172	
1173	\begin{table}[t]
1174	\centering
1175	\small
1176	\caption{Few-NERD INTRA coarse: complete quality estimation and selection results (Qwen3-8B, $N{=}8$, $T{=}1.0$, gold-filtered $n{=}32{,}565$). $\rho$: Spearman correlation with instance F1. Sample AUROC: per-sample LP discrimination. Sel.\ $\Delta$: selection F1 minus greedy (0.748). CI: bootstrap 95\% confidence interval.}
1177	\label{tab:fewnerd_full}
1178	\begin{tabular}{lcccc}
1179	\toprule
1180	Signal & $\rho$ & Sample AUROC & Sel.\ $\Delta$ & 95\% CI \\
1181	\midrule
1182	LP & .421 & .578 & $\mathbf{+1.36}$\,pp & [+1.18, +1.53] \\
1183	VC & .386 & --- & $-$1.79\,pp & --- \\
1184	FK & .313 & --- & $-$2.26\,pp & --- \\
1185	SJ & .300 & --- & $-$2.14\,pp & --- \\
1186	EM & .287 & --- & $-$3.85\,pp & --- \\
1187	\midrule
1188	\multicolumn{3}{l}{Greedy: 0.748 \quad Oracle: 0.872} & \multicolumn{2}{l}{Headroom: 12.4\,pp} \\
1189	\bottomrule
1190	\end{tabular}
1191	\end{table}
1192	
1193	\paragraph{Key observations.}
1194	(1)~All five signals achieve positive QE ($\rho$ 0.29--0.42); quality estimation works on Few-NERD. LP leads ($\rho{=}0.42$), followed by VC ($0.39$); the ranking differs from SciERC where VC leads, consistent with dataset-specific signal informativeness.
1195	(2)~LP is the only signal achieving significant positive selection ($+1.36$~pp, $p{<}0.001$, CI excludes zero). The sample-level AUROC of 0.578 confirms LP provides per-sample discriminability beyond instance-level quality prediction.
1196	(3)~Despite positive $\rho$, all structural signals degrade selection ($-1.79$ to $-3.85$~pp), further confirming that the correlation-selection gap is not an artifact of weak QE.
1197	(4)~Low degeneracy (13.8\%) combined with strong LP-quality alignment ($\rho{\approx}0.5$) enables LP selection: candidates differ in F1 more often, and LP can rank them effectively. This contrasts with SciERC (17.8\% degeneracy but weak alignment $\rho{\approx}0.24$, LP $+0.61$~pp) and CoNLL (59.1\%, LP $-1.05$~pp).
1198	
1199	\section{Per-Entity-Type LP Selection Analysis}\label{app:per_type_lp}
1200	
1201	Table~\ref{tab:per_type_lp} stratifies LP selection by entity type on Few-NERD, sorted by degeneracy rate.
1202	The degeneracy-gating mechanism holds at entity-type granularity: 7 of 8 types show positive LP selection gains, and the sole negative type (Art, $-0.17$~pp) has the highest degeneracy (19.8\%).
1203	The correlation between per-type degeneracy and oracle headroom is strong and significant (Spearman $\rho{=}{-}0.881$, $p{=}0.004$); degeneracy directly constrains the headroom available for selection.
1204	
1205	\begin{table}[h]
1206	\centering
1207	\small
1208	\caption{Per-entity-type LP selection on Few-NERD INTRA coarse (Qwen3-8B, $N{=}8$, $T{=}1.0$), sorted by degeneracy. LP $\Delta$: LP selection F1 minus greedy. 7/8 types show positive $\Delta$; Art (highest degeneracy) is the sole exception.}
1209	\label{tab:per_type_lp}
1210	\begin{tabular}{lrrrrrrr}
1211	\toprule
1212	Entity Type & $n$ & Degen.\% & Greedy & LP Sel & $\Delta$ (pp) & LP $\rho$ & Headroom \\
1213	\midrule
1214	Event & 1{,}306 & 6.0 & .655 & .662 & $+$0.65 & .457 & 16.1\,pp \\
1215	Other & 3{,}433 & 6.6 & .637 & .685 & $\mathbf{+4.73}$ & .491 & 19.4\,pp \\
1216	Organization & 6{,}647 & 6.7 & .720 & .732 & $+$1.21 & .509 & 13.3\,pp \\
1217	Building & 1{,}587 & 7.2 & .702 & .705 & $+$0.23 & .478 & 14.9\,pp \\
1218	Product & 2{,}276 & 8.2 & .656 & .677 & $+$2.01 & .483 & 15.8\,pp \\
1219	Location & 8{,}023 & 11.4 & .793 & .798 & $+$0.53 & .520 & 10.3\,pp \\
1220	Person & 8{,}016 & 13.4 & .822 & .835 & $+$1.25 & .544 & 9.2\,pp \\
1221	Art & 1{,}277 & 19.8 & .756 & .754 & $-$0.17 & .451 & 9.2\,pp \\
1222	\bottomrule
1223	\end{tabular}
1224	\end{table}
1225	
1226	\begin{table}[h]
1227	\centering
1228	\small
1229	\caption{CoNLL-2003 per-type LP selection (Qwen3-8B, $N{=}16$, $T{=}1.0$). All types exceed 20\% degeneracy and show negative LP selection, consistent with the dataset's ceiling-regime performance (F1 $>$ 90\%).}
1230	\label{tab:per_type_lp_conll}
1231	\begin{tabular}{lrrr}
1232	\toprule
1233	Entity Type & Degen.\% & LP $\Delta$ (pp) \\
1234	\midrule
1235	MISC & 23.2 & $-$2.19 \\
1236	PER & 42.6 & $-$1.08 \\
1237	LOC & 47.5 & $-$0.62 \\
1238	ORG & 54.3 & $-$0.55 \\
1239	\bottomrule
1240	\end{tabular}
1241	\end{table}
1242	
1243	\begin{table}[h]
1244	\centering
1245	\small
1246	\caption{SciERC per-type LP selection (Qwen3-8B, $N{=}8$, $T{=}1.0$). Within-dataset, degeneracy alone does not predict LP effectiveness (Spearman $\rho{=}0.14$, $p{=}0.79$); additional type-specific factors likely modulate selection at this granularity.}
1247	\label{tab:per_type_lp_scierc}
1248	\begin{tabular}{lrrr}
1249	\toprule
1250	Entity Type & Degen.\% & LP $\Delta$ (pp) \\
1251	\midrule
1252	Task & 10.1 & $+$2.58 \\
1253	Generic & 10.0 & $+$2.07 \\
1254	Material & 20.0 & $+$0.91 \\
1255	Metric & 12.5 & $-$0.06 \\
1256	Method & 16.3 & $-$0.03 \\
1257	OtherScientificTerm & 6.2 & $-$0.57 \\
1258	\bottomrule
1259	\end{tabular}
1260	\end{table}
1261	
1262	The cross-dataset degeneracy gradient (59.1\% $\to$ 17.8\% $\to$ 13.8\%) is inversely associated with LP selection effectiveness at the macro level ($n{=}3$ datasets; exploratory).\footnote{Partial Spearman correlation controlling for entity-type frequency yields $\rho{=}{-}0.47$ (vs.\ raw $\rho{=}{-}0.38$); type frequency does not confound the degeneracy--LP relationship.}
1263	At finer per-type granularity, selection depends on the interaction of degeneracy, oracle headroom, and type-specific LP-quality alignment.
1264	Low degeneracy is necessary but not sufficient: CoNLL MISC (23\%, headroom 12.6~pp) and SciERC OtherScientificTerm (6.2\%, headroom 12.5~pp) both show negative LP selection despite available headroom; LP correlation strength with the type-specific quality function is an additional prerequisite.
1265	
1266	\section{Calibration Baseline}\label{app:calibration_baseline}
1267	
1268	Standard calibration methods are monotonic transforms of log-probability and therefore preserve within-instance sample rankings: Platt scaling \cite{platt1999probabilistic} fits a logistic regression $\sigma(a \cdot \text{LP} + b)$, and temperature scaling \cite{guo2017calibration} divides logits by a scalar $\tau$.
1269	Since both preserve the argmax, selection F1 is identical to raw LP on all three datasets (Table~\ref{tab:calibration}).
1270	
1271	To break monotonicity, we fit a multi-feature Platt model (MF-Platt) using LP, token count, and entity count as inputs, trained on a held-out calibration split (20\% of the test set, 5-fold cross-validation on the remainder).
1272	MF-Platt can reorder candidates within an instance, yet yields no significant selection improvement: $\Delta{=}{-}1.1$~pp on SciERC ($p{=}0.72$), $+0.3$~pp on CoNLL ($p{=}0.31$), and $-0.6$~pp on Few-NERD ($p{=}0.83$).
1273	Platt scaling substantially improves probability calibration (ECE drops from 0.26--0.39 to 0.01--0.08), but better-calibrated probabilities do not translate to better selection.
1274	This parallels the supervised verifier result (\S\ref{sec:robustness_main}): neither stronger aggregation nor additional features can compensate for weak per-sample discriminative signal.
1275	
1276	\begin{table}[t]
1277	\centering
1278	\small
1279	\caption{Calibration baseline results ($N{=}8$, $T{=}1.0$). Platt and TempScale are monotonic transforms of LP that preserve the within-instance argmax (selection F1 $\equiv$ Raw LP, omitted). MF-Platt uses LP $+$ token count $+$ entity count; $p$: bootstrap test vs.\ Raw LP.}
1280	\label{tab:calibration}
1281	\begin{tabular}{l cccc cc}
1282	\toprule
1283	& & \multicolumn{2}{c}{Selection F1} & & \multicolumn{2}{c}{ECE} \\
1284	\cmidrule(lr){3-4} \cmidrule(lr){6-7}
1285	Dataset & Greedy & Raw LP & MF-Platt ($p$) & & Raw & Platt \\
1286	\midrule
1287	SciERC & .644 & .650 & .639 (.72) & & .260 & .048 \\
1288	CoNLL & .909 & .898 & .901 (.31) & & .392 & .012 \\
1289	Few-NERD & .771 & .785 & .778 (.83) & & .262 & .080 \\
1290	\bottomrule
1291	\end{tabular}
1292	\end{table}
1293	
1294	\section{Epoch Confound Analysis}\label{app:epoch_confound}
1295	
1296	\paragraph{Training convergence modulates degeneracy.}
1297	Table~\ref{tab:epoch_confound} compares the 3-epoch model (used throughout the main text) with a 5-epoch variant on Few-NERD (Qwen3-8B, $N{=}8$, $T{=}1.0$).
1298	Extended training increases greedy F1 by $+2.95$~pp (0.748 $\to$ 0.777) but nearly triples instance degeneracy (11.1\% $\to$ 31.3\%), reducing the fraction of instances with non-degenerate outputs from 85.6\% to 68.7\%.
1299	LP selection gains drop correspondingly ($+1.37$~pp $\to$ $+0.62$~pp), consistent with the degeneracy-gating mechanism identified in the main text (\S\ref{sec:discussion}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "ef378709-8f42-4f99-88f4-c7d0e7b3dc30",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "This extends the capability boundary identified on WNUT-17 to the domain-shift setting: confidence signals require sufficient model capability as a prerequisite, and results from the CoNLL$\\to$SciERC direction should not be interpreted as evidence of signal degradation under domain shift.\n\n\\section{Verbalized Confidence}\\label{app:verbalized_confidence}\n\nWe evaluate verbalized confidence (VerbConf) as a second per-sample signal following \\citet{tian2023calibration}: after generating each structured output, the model is prompted to rate its confidence on a 1--10 scale.\nTable~\\ref{tab:verbconf} reports quality estimation and selection results.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Verbalized confidence (VerbConf) vs.\\ log-probability selection (Qwen3-8B, $N{=}8$, $T{=}1.0$, seed${=}42$). Parse fail: fraction of samples where the confidence score could not be extracted.}\n\\label{tab:verbconf}\n\\begin{tabular}{l cc cc}\n\\toprule\n & \\multicolumn{2}{c}{\\textbf{SciERC NER}} & \\multicolumn{2}{c}{\\textbf{CoNLL NER}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nMetric & VerbConf & LP & VerbConf & LP \\\\\n\\midrule\n$\\rho$ & 0.297 & 0.205 & 0.337 & 0.316 \\\\\nAUROC & 0.681 & 0.578 & 0.747 & 0.753 \\\\\nSelection F1 & 0.620 & 0.647 & 0.889 & 0.904 \\\\\n$\\Delta$ vs.\\ greedy & $-$2.45\\,pp & $+$0.2\\,pp & $-$1.93\\,pp & $-$0.77\\,pp \\\\\n\\midrule\nMean score & 8.58\\,/\\,10 & --- & 9.24\\,/\\,10 & --- \\\\\nParse fail rate & 0.26\\% & --- & 0\\% & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Severe overconfidence.}\nVerbConf exhibits extreme score compression: mean confidence is 8.58/10 on SciERC (single-sample F1${=}0.645$) and 9.24/10 on CoNLL (single-sample F1${=}0.904$), with most scores concentrated in the 8--10 range.\nThis compression is more severe than LP (which spans a 0.041-nat median range); score compression is a general property of model self-assessment, not an artifact of log-probability computation.\n\n\\paragraph{QE--selection decoupling.}\nVerbConf achieves higher $\\rho$ than LP on both datasets (SciERC: 0.297 vs.\\ 0.205; CoNLL: 0.337 vs.\\ 0.316) and competitive AUROC (SciERC: 0.681 vs.\\ 0.578; CoNLL: 0.747 vs.\\ 0.753), yet yields the worst selection among all signals ($\\Delta{=}{-}2.45$~pp on SciERC, $-1.93$~pp on CoNLL).\nThis dissociation further demonstrates the correlation-selection gap: a signal can rank instances by expected quality without being able to discriminate candidates within an instance.\nThe AUROC--$\\rho$ decoupling on CoNLL (LP leads AUROC at 0.753 while VerbConf leads $\\rho$ at 0.337) reflects differing sensitivity to binary vs.\\ ordinal discrimination.\n\n\\section{LLaMA-3.2-3B Scale Ablation}\\label{app:llama3b}\n\nTo extend scale coverage below 4B, we fine-tune LLaMA-3.2-3B-Instruct on SciERC NER under identical training conditions (LoRA rank${=}32$, $\\alpha{=}64$, 5 epochs) and evaluate quality estimation and selection (Table~\\ref{tab:llama3b}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{LLaMA-3.2-3B SciERC NER quality estimation and selection ($N{=}8$, $T{=}1.0$, seed${=}42$). Greedy F1${=}0.627$, Oracle F1${=}0.763$, headroom${=}13.63$~pp.}\n\\label{tab:llama3b}\n\\begin{tabular}{l cc cc}\n\\toprule\nSignal & $\\rho$ & AUROC & Sel.\\ F1 & $\\Delta$ vs.\\ greedy \\\\\n\\midrule\nVC & \\textbf{.460} & .743 & 0.611 & $-$1.54\\,pp \\\\\nSJ & .375 & .738 & \\textbf{0.633} & $+$0.61\\,pp \\\\\nEM & .334 & \\textbf{.776} & --- & --- \\\\\nFK & .268 & .671 & 0.630 & $+$0.28\\,pp \\\\\nLP & .266 & .633 & 0.628 & $+$0.12\\,pp \\\\\n\\midrule\nGreedy & --- & --- & 0.627 & --- \\\\\nOracle & --- & --- & 0.763 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe $\\rho$ ranking at 3B (VC $>$ SJ $>$ EM $>$ FK $\\approx$ LP) preserves the structural-over-LP ordering from 8B (Table~\\ref{tab:quality_estimation}); ranking stability holds across two model families spanning 3B--8B.\nAUROC rankings differ (EM $>$ VC $>$ SJ $>$ FK $>$ LP), consistent with the $\\rho$--AUROC dissociation noted in the main text.\nDespite 13.63~pp of oracle headroom, no signal achieves significant selection improvement (best: SJ, $+0.61$~pp, $p{=}0.175$); VC, the strongest QE signal, yields the worst selection ($-1.54$~pp), consistent with the correlation-selection gap observed at larger scales.\n\n\\section{Few-NERD Full Results}\\label{app:fewnerd}\n\nTable~\\ref{tab:fewnerd_full} reports the complete Few-NERD INTRA coarse evaluation (Qwen3-8B, LoRA rank${=}32$, 3 epochs, $N{=}8$, $T{=}1.0$).\nAfter gold-filtering (removing instances with no gold entities), the evaluation set contains $n{=}32{,}565$ instances across 8 coarse entity types; 11.9\\% receive zero F1 under greedy decoding.\nInstance degeneracy is 13.8\\% (vs.\\ 17.8\\% on SciERC, 59.1\\% on CoNLL).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Few-NERD INTRA coarse: complete quality estimation and selection results (Qwen3-8B, $N{=}8$, $T{=}1.0$, gold-filtered $n{=}32{,}565$). $\\rho$: Spearman correlation with instance F1. Sample AUROC: per-sample LP discrimination. Sel.\\ $\\Delta$: selection F1 minus greedy (0.748). CI: bootstrap 95\\% confidence interval.}\n\\label{tab:fewnerd_full}\n\\begin{tabular}{lcccc}\n\\toprule\nSignal & $\\rho$ & Sample AUROC & Sel.\\ $\\Delta$ & 95\\% CI \\\\\n\\midrule\nLP & .421 & .578 & $\\mathbf{+1.36}$\\,pp & [+1.18, +1.53] \\\\\nVC & .386 & --- & $-$1.79\\,pp & --- \\\\\nFK & .313 & --- & $-$2.26\\,pp & --- \\\\\nSJ & .300 & --- & $-$2.14\\,pp & --- \\\\\nEM & .287 & --- & $-$3.85\\,pp & --- \\\\\n\\midrule\n\\multicolumn{3}{l}{Greedy: 0.748 \\quad Oracle: 0.872} & \\multicolumn{2}{l}{Headroom: 12.4\\,pp} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Key observations.}\n(1)~All five signals achieve positive QE ($\\rho$ 0.29--0.42); quality estimation works on Few-NERD. LP leads ($\\rho{=}0.42$), followed by VC ($0.39$); the ranking differs from SciERC where VC leads, consistent with dataset-specific signal informativeness.\n(2)~LP is the only signal achieving significant positive selection ($+1.36$~pp, $p{<}0.001$, CI excludes zero). The sample-level AUROC of 0.578 confirms LP provides per-sample discriminability beyond instance-level quality prediction.\n(3)~Despite positive $\\rho$, all structural signals degrade selection ($-1.79$ to $-3.85$~pp), further confirming that the correlation-selection gap is not an artifact of weak QE.\n(4)~Low degeneracy (13.8\\%) combined with strong LP-quality alignment ($\\rho{\\approx}0.5$) enables LP selection: candidates differ in F1 more often, and LP can rank them effectively. This contrasts with SciERC (17.8\\% degeneracy but weak alignment $\\rho{\\approx}0.24$, LP $+0.61$~pp) and CoNLL (59.1\\%, LP $-1.05$~pp).\n\n\\section{Per-Entity-Type LP Selection Analysis}\\label{app:per_type_lp}\n\nTable~\\ref{tab:per_type_lp} stratifies LP selection by entity type on Few-NERD, sorted by degeneracy rate.\nThe degeneracy-gating mechanism holds at entity-type granularity: 7 of 8 types show positive LP selection gains, and the sole negative type (Art, $-0.17$~pp) has the highest degeneracy (19.8\\%).\nThe correlation between per-type degeneracy and oracle headroom is strong and significant (Spearman $\\rho{=}{-}0.881$, $p{=}0.004$); degeneracy directly constrains the headroom available for selection.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-entity-type LP selection on Few-NERD INTRA coarse (Qwen3-8B, $N{=}8$, $T{=}1.0$), sorted by degeneracy. LP $\\Delta$: LP selection F1 minus greedy. 7/8 types show positive $\\Delta$; Art (highest degeneracy) is the sole exception.}\n\\label{tab:per_type_lp}\n\\begin{tabular}{lrrrrrrr}\n\\toprule\nEntity Type & $n$ & Degen.\\% & Greedy & LP Sel & $\\Delta$ (pp) & LP $\\rho$ & Headroom \\\\\n\\midrule\nEvent & 1{,}306 & 6.0 & .655 & .662 & $+$0.65 & .457 & 16.1\\,pp \\\\\nOther & 3{,}433 & 6.6 & .637 & .685 & $\\mathbf{+4.73}$ & .491 & 19.4\\,pp \\\\\nOrganization & 6{,}647 & 6.7 & .720 & .732 & $+$1.21 & .509 & 13.3\\,pp \\\\\nBuilding & 1{,}587 & 7.2 & .702 & .705 & $+$0.23 & .478 & 14.9\\,pp \\\\\nProduct & 2{,}276 & 8.2 & .656 & .677 & $+$2.01 & .483 & 15.8\\,pp \\\\\nLocation & 8{,}023 & 11.4 & .793 & .798 & $+$0.53 & .520 & 10.3\\,pp \\\\\nPerson & 8{,}016 & 13.4 & .822 & .835 & $+$1.25 & .544 & 9.2\\,pp \\\\\nArt & 1{,}277 & 19.8 & .756 & .754 & $-$0.17 & .451 & 9.2\\,pp \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{CoNLL-2003 per-type LP selection (Qwen3-8B, $N{=}16$, $T{=}1.0$). All types exceed 20\\% degeneracy and show negative LP selection, consistent with the dataset's ceiling-regime performance (F1 $>$ 90\\%).}\n\\label{tab:per_type_lp_conll}\n\\begin{tabular}{lrrr}\n\\toprule\nEntity Type & Degen.\\% & LP $\\Delta$ (pp) \\\\\n\\midrule\nMISC & 23.2 & $-$2.19 \\\\\nPER & 42.6 & $-$1.08 \\\\\nLOC & 47.5 & $-$0.62 \\\\\nORG & 54.3 & $-$0.55 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{SciERC per-type LP selection (Qwen3-8B, $N{=}8$, $T{=}1.0$). Within-dataset, degeneracy alone does not predict LP effectiveness (Spearman $\\rho{=}0.14$, $p{=}0.79$); additional type-specific factors likely modulate selection at this granularity.}\n\\label{tab:per_type_lp_scierc}\n\\begin{tabular}{lrrr}\n\\toprule\nEntity Type & Degen.\\% & LP $\\Delta$ (pp) \\\\\n\\midrule\nTask & 10.1 & $+$2.58 \\\\\nGeneric & 10.0 & $+$2.07 \\\\\nMaterial & 20.0 & $+$0.91 \\\\\nMetric & 12.5 & $-$0.06 \\\\\nMethod & 16.3 & $-$0.03 \\\\\nOtherScientificTerm & 6.2 & $-$0.57 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe cross-dataset degeneracy gradient (59.1\\% $\\to$ 17.8\\% $\\to$ 13.8\\%) is inversely associated with LP selection effectiveness at the macro level ($n{=}3$ datasets; exploratory).\\footnote{Partial Spearman correlation controlling for entity-type frequency yields $\\rho{=}{-}0.47$ (vs.\\ raw $\\rho{=}{-}0.38$); type frequency does not confound the degeneracy--LP relationship.}\nAt finer per-type granularity, selection depends on the interaction of degeneracy, oracle headroom, and type-specific LP-quality alignment.\nLow degeneracy is necessary but not sufficient: CoNLL MISC (23\\%, headroom 12.6~pp) and SciERC OtherScientificTerm (6.2\\%, headroom 12.5~pp) both show negative LP selection despite available headroom; LP correlation strength with the type-specific quality function is an additional prerequisite.\n\n\\section{Calibration Baseline}\\label{app:calibration_baseline}\n\nStandard calibration methods are monotonic transforms of log-probability and therefore preserve within-instance sample rankings: Platt scaling \\cite{platt1999probabilistic} fits a logistic regression $\\sigma(a \\cdot \\text{LP} + b)$, and temperature scaling \\cite{guo2017calibration} divides logits by a scalar $\\tau$.\nSince both preserve the argmax, selection F1 is identical to raw LP on all three datasets (Table~\\ref{tab:calibration}).\n\nTo break monotonicity, we fit a multi-feature Platt model (MF-Platt) using LP, token count, and entity count as inputs, trained on a held-out calibration split (20\\% of the test set, 5-fold cross-validation on the remainder).\nMF-Platt can reorder candidates within an instance, yet yields no significant selection improvement: $\\Delta{=}{-}1.1$~pp on SciERC ($p{=}0.72$), $+0.3$~pp on CoNLL ($p{=}0.31$), and $-0.6$~pp on Few-NERD ($p{=}0.83$).\nPlatt scaling substantially improves probability calibration (ECE drops from 0.26--0.39 to 0.01--0.08), but better-calibrated probabilities do not translate to better selection.\nThis parallels the supervised verifier result (\\S\\ref{sec:robustness_main}): neither stronger aggregation nor additional features can compensate for weak per-sample discriminative signal.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Calibration baseline results ($N{=}8$, $T{=}1.0$). Platt and TempScale are monotonic transforms of LP that preserve the within-instance argmax (selection F1 $\\equiv$ Raw LP, omitted). MF-Platt uses LP $+$ token count $+$ entity count; $p$: bootstrap test vs.\\ Raw LP.}\n\\label{tab:calibration}\n\\begin{tabular}{l cccc cc}\n\\toprule\n& & \\multicolumn{2}{c}{Selection F1} & & \\multicolumn{2}{c}{ECE} \\\\\n\\cmidrule(lr){3-4} \\cmidrule(lr){6-7}\nDataset & Greedy & Raw LP & MF-Platt ($p$) & & Raw & Platt \\\\\n\\midrule\nSciERC & .644 & .650 & .639 (.72) & & .260 & .048 \\\\\nCoNLL & .909 & .898 & .901 (.31) & & .392 & .012 \\\\\nFew-NERD & .771 & .785 & .778 (.83) & & .262 & .080 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Epoch Confound Analysis}\\label{app:epoch_confound}\n\n\\paragraph{Training convergence modulates degeneracy.}\nTable~\\ref{tab:epoch_confound} compares the 3-epoch model (used throughout the main text) with a 5-epoch variant on Few-NERD (Qwen3-8B, $N{=}8$, $T{=}1.0$).\nExtended training increases greedy F1 by $+2.95$~pp (0.748 $\\to$ 0.777) but nearly triples instance degeneracy (11.1\\% $\\to$ 31.3\\%), reducing the fraction of instances with non-degenerate outputs from 85.6\\% to 68.7\\%.\nLP selection gains drop correspondingly ($+1.37$~pp $\\to$ $+0.62$~pp), consistent with the degeneracy-gating mechanism identified in the main text (\\S\\ref{sec:discussion}).",
      "numLines": 200,
      "startLine": 1100,
      "totalLines": 1354
    }
  }
}
```

</details>

---

### Assistant

_source line 77_

<details><summary>Logged reasoning block</summary>

```text
Let me now read the rest of the appendix to complete the audit.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "e5165498-c407-4045-9f10-33e4b6b97864",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01USVtdmrW4qL9PSHSFg2n6J",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23443,
      "cache_read_input_tokens": 69317,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 23443
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

_source line 78_

继续读取剩余 appendix 部分。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "64b093cc-f16a-461e-95b9-37186dd713bc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01USVtdmrW4qL9PSHSFg2n6J",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23443,
      "cache_read_input_tokens": 69317,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 23443
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

_source line 79_

<details open><summary>🔧 Tool call — Read · `toolu_01FTqU3u89zMLLu7w89BX82j`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "offset": 1300,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "237d8c58-f8a0-4cf3-b880-21b7db39f268",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01USVtdmrW4qL9PSHSFg2n6J",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23443,
      "cache_read_input_tokens": 69317,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 23443
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

_source line 80 · 2026-05-18T05:47:17.514Z_

<details><summary>↩ Tool result · `toolu_01FTqU3u89zMLLu7w89BX82j`</summary>

```text
1300	Within-instance LP-quality alignment is relatively stable under this convergence shift (mean $\rho$: $0.524 \to 0.407$; median $\rho$: $0.667 \to 0.615$), consistent with alignment being determined primarily by task structure rather than training duration.
1301	
1302	Evaluation loss increases after epoch 3 (0.032 $\to$ 0.041 at epoch 5), and the best checkpoint by validation loss occurs at step 32{,}000 (approximately epoch 3.9).
1303	Standard early stopping practice thus naturally selects the low-degeneracy regime where LP selection is most effective.
1304	This finding refines the narrative: degeneracy is not a fixed property of datasets but is modulated by the degree of training convergence. Over-trained models compress their output distributions, collapsing diversity even on datasets that support it under well-regularized training.
1305	
1306	\begin{table}[t]
1307	\centering
1308	\small
1309	\caption{Training convergence confound on Few-NERD (Qwen3-8B, $N{=}8$, $T{=}1.0$). ``Degen.'': constant-F1 instance degeneracy (gold-filtered). ``Valid'': fraction of instances with non-degenerate outputs. ``$\rho$ mean/med'': within-instance LP-quality correlation. The 3-epoch model corresponds to standard early stopping; the 5-epoch model is a controlled ablation.}
1310	\label{tab:epoch_confound}
1311	\begin{tabular}{lcc}
1312	\toprule
1313	Metric & 3-epoch & 5-epoch \\
1314	\midrule
1315	Greedy F1 & 0.748 & 0.777 \\
1316	Instance degen.\ (\%) & 11.1 & 31.3 \\
1317	Valid instances & 3{,}723 / 4{,}351 (85.6\%) & 2{,}988 / 4{,}351 (68.7\%) \\
1318	LP $\Delta$ (pp) & $+$1.37 & $+$0.62 \\
1319	Within-inst.\ $\rho$ (mean) & 0.524 & 0.407 \\
1320	Within-inst.\ $\rho$ (median) & 0.667 & 0.615 \\
1321	\bottomrule
1322	\end{tabular}
1323	\end{table}
1324	
1325	\paragraph{SciERC epoch curve.}
1326	Table~\ref{tab:epoch_scierc} extends the analysis to SciERC with a 3-point curve (3, 5, 10 epochs; Qwen3-8B, $N{=}8$, $T{=}1.0$).
1327	Degeneracy increases monotonically (6.4\% $\to$ 17.8\% $\to$ 47.8\%), and within-instance LP-quality correlation degrades in tandem (median $\rho$: 0.317 $\to$ 0.282 $\to$ 0.120), confirming that overtraining erodes both necessary conditions simultaneously.
1328	LP selection does not yield significant gains at any training duration ($-1.18$, $+0.62$, $+0.75$~pp; all below the ${\approx}$1.5~pp MDE), despite oracle headroom ranging from 8.4 to 15.0~pp.
1329	At 10 epochs, the model retains competitive greedy F1 (0.649 vs.\ 0.650 at 3 epochs) yet both conditions are violated: 47.8\% degenerate instances and $\rho{=}0.120$.
1330	The gradient confirms that degeneracy is convergence-driven rather than a fixed dataset property: extended training compresses output distributions, degrading both diversity and within-instance alignment. However, even at 3 epochs (lowest degeneracy, 6.4\%), SciERC's within-instance alignment ($\rho{=}0.317$) remains below the threshold observed on Few-NERD ($\rho{\sim}0.5$), reinforcing that controlling degeneracy alone is insufficient when the alignment condition is not met.
1331	
1332	\begin{table}[t]
1333	\centering
1334	\small
1335	\caption{SciERC NER epoch curve (Qwen3-8B, $N{=}8$, $T{=}1.0$). Training duration modulates both instance degeneracy and within-instance LP-quality alignment. ``Degen.'': constant-F1 instance degeneracy (gold-filtered). ``LP $\Delta$'': LP selection gain over greedy (gold-filtered; none reaches the ${\approx}$1.5~pp MDE). ``$\rho$ med'': median within-instance LP-quality correlation.}
1336	\label{tab:epoch_scierc}
1337	\begin{tabular}{lccc}
1338	\toprule
1339	Metric & 3-epoch & 5-epoch & 10-epoch \\
1340	\midrule
1341	Greedy F1 & 0.650 & 0.644 & 0.649 \\
1342	Instance degen.\ (\%) & 6.4 & 17.8 & 47.8 \\
1343	LP $\Delta$ (pp) & $-$1.18 & $+$0.62 & $+$0.75 \\
1344	Within-inst.\ $\rho$ (median) & 0.317 & 0.282 & 0.120 \\
1345	\bottomrule
1346	\end{tabular}
1347	\end{table}
1348	
1349	\paragraph{Limitations.}
1350	The Few-NERD epoch analysis covers 2 points (3 vs.\ 5 epochs); the SciERC curve provides a 3-point gradient showing monotonic degeneracy increase with simultaneous within-instance alignment degradation.
1351	CoNLL epoch variation remains unverified; high-degeneracy datasets (CoNLL at 59--86\%) may exhibit a ceiling effect where additional training has limited marginal impact.
1352	All Few-NERD results in the main text use the 3-epoch model (standard early stopping); the 5-epoch comparison is a controlled ablation.
1353	All SciERC results use the 5-epoch model; the 3- and 10-epoch variants serve as controlled ablations.
1354	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "59d1830c-dd84-47b7-9c37-4cd63ef3bf56",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "Within-instance LP-quality alignment is relatively stable under this convergence shift (mean $\\rho$: $0.524 \\to 0.407$; median $\\rho$: $0.667 \\to 0.615$), consistent with alignment being determined primarily by task structure rather than training duration.\n\nEvaluation loss increases after epoch 3 (0.032 $\\to$ 0.041 at epoch 5), and the best checkpoint by validation loss occurs at step 32{,}000 (approximately epoch 3.9).\nStandard early stopping practice thus naturally selects the low-degeneracy regime where LP selection is most effective.\nThis finding refines the narrative: degeneracy is not a fixed property of datasets but is modulated by the degree of training convergence. Over-trained models compress their output distributions, collapsing diversity even on datasets that support it under well-regularized training.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Training convergence confound on Few-NERD (Qwen3-8B, $N{=}8$, $T{=}1.0$). ``Degen.'': constant-F1 instance degeneracy (gold-filtered). ``Valid'': fraction of instances with non-degenerate outputs. ``$\\rho$ mean/med'': within-instance LP-quality correlation. The 3-epoch model corresponds to standard early stopping; the 5-epoch model is a controlled ablation.}\n\\label{tab:epoch_confound}\n\\begin{tabular}{lcc}\n\\toprule\nMetric & 3-epoch & 5-epoch \\\\\n\\midrule\nGreedy F1 & 0.748 & 0.777 \\\\\nInstance degen.\\ (\\%) & 11.1 & 31.3 \\\\\nValid instances & 3{,}723 / 4{,}351 (85.6\\%) & 2{,}988 / 4{,}351 (68.7\\%) \\\\\nLP $\\Delta$ (pp) & $+$1.37 & $+$0.62 \\\\\nWithin-inst.\\ $\\rho$ (mean) & 0.524 & 0.407 \\\\\nWithin-inst.\\ $\\rho$ (median) & 0.667 & 0.615 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{SciERC epoch curve.}\nTable~\\ref{tab:epoch_scierc} extends the analysis to SciERC with a 3-point curve (3, 5, 10 epochs; Qwen3-8B, $N{=}8$, $T{=}1.0$).\nDegeneracy increases monotonically (6.4\\% $\\to$ 17.8\\% $\\to$ 47.8\\%), and within-instance LP-quality correlation degrades in tandem (median $\\rho$: 0.317 $\\to$ 0.282 $\\to$ 0.120), confirming that overtraining erodes both necessary conditions simultaneously.\nLP selection does not yield significant gains at any training duration ($-1.18$, $+0.62$, $+0.75$~pp; all below the ${\\approx}$1.5~pp MDE), despite oracle headroom ranging from 8.4 to 15.0~pp.\nAt 10 epochs, the model retains competitive greedy F1 (0.649 vs.\\ 0.650 at 3 epochs) yet both conditions are violated: 47.8\\% degenerate instances and $\\rho{=}0.120$.\nThe gradient confirms that degeneracy is convergence-driven rather than a fixed dataset property: extended training compresses output distributions, degrading both diversity and within-instance alignment. However, even at 3 epochs (lowest degeneracy, 6.4\\%), SciERC's within-instance alignment ($\\rho{=}0.317$) remains below the threshold observed on Few-NERD ($\\rho{\\sim}0.5$), reinforcing that controlling degeneracy alone is insufficient when the alignment condition is not met.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{SciERC NER epoch curve (Qwen3-8B, $N{=}8$, $T{=}1.0$). Training duration modulates both instance degeneracy and within-instance LP-quality alignment. ``Degen.'': constant-F1 instance degeneracy (gold-filtered). ``LP $\\Delta$'': LP selection gain over greedy (gold-filtered; none reaches the ${\\approx}$1.5~pp MDE). ``$\\rho$ med'': median within-instance LP-quality correlation.}\n\\label{tab:epoch_scierc}\n\\begin{tabular}{lccc}\n\\toprule\nMetric & 3-epoch & 5-epoch & 10-epoch \\\\\n\\midrule\nGreedy F1 & 0.650 & 0.644 & 0.649 \\\\\nInstance degen.\\ (\\%) & 6.4 & 17.8 & 47.8 \\\\\nLP $\\Delta$ (pp) & $-$1.18 & $+$0.62 & $+$0.75 \\\\\nWithin-inst.\\ $\\rho$ (median) & 0.317 & 0.282 & 0.120 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Limitations.}\nThe Few-NERD epoch analysis covers 2 points (3 vs.\\ 5 epochs); the SciERC curve provides a 3-point gradient showing monotonic degeneracy increase with simultaneous within-instance alignment degradation.\nCoNLL epoch variation remains unverified; high-degeneracy datasets (CoNLL at 59--86\\%) may exhibit a ceiling effect where additional training has limited marginal impact.\nAll Few-NERD results in the main text use the 3-epoch model (standard early stopping); the 5-epoch comparison is a controlled ablation.\nAll SciERC results use the 5-epoch model; the 3- and 10-epoch variants serve as controlled ablations.\n",
      "numLines": 55,
      "startLine": 1300,
      "totalLines": 1354
    }
  }
}
```

</details>

---

### Tool call

_source line 81_

<details open><summary>🔧 Tool call — Grep · `toolu_011qbH1oghe9J1Q8mjv6ApJZ`</summary>

```json
{
  "pattern": "0\\.215",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "c10a2ba2-c087-4601-8aa6-d0d62e1d9799",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01USVtdmrW4qL9PSHSFg2n6J",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23443,
      "cache_read_input_tokens": 69317,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 23443
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

_source line 82 · 2026-05-18T05:47:18.450Z_

<details><summary>↩ Tool result · `toolu_011qbH1oghe9J1Q8mjv6ApJZ`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "87d316f0-cd03-4da3-ac01-8635746a7786",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 83_

<details open><summary>🔧 Tool call — Grep · `toolu_01SB6EvuhVjZb1xgr9mNadFp`</summary>

```json
{
  "pattern": "0\\.61",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "4a04fafa-fd3b-4422-8187-8b0a85de2074",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01USVtdmrW4qL9PSHSFg2n6J",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23443,
      "cache_read_input_tokens": 69317,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 23443
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

_source line 84 · 2026-05-18T05:47:19.228Z_

<details><summary>↩ Tool result · `toolu_01SB6EvuhVjZb1xgr9mNadFp`</summary>

```text
docs/paper/sections/experiments.tex:80:Random           & $0.610 \pm 0.003$ & --- \\
docs/paper/sections/experiments.tex:108:SciERC & 529 & .644 & 13.2\,pp & 17.8\% & .215 & $+$0.61\,pp \\
docs/paper/sections/experiments.tex:120:The cross-dataset gradient is consistent with an inverse relationship (59.1\% $\to$ $-1.05$~pp, 17.8\% $\to$ $+0.61$~pp, 13.8\% $\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory given 5+ confounds; Figure~\ref{fig:degeneracy_scatter}), with supporting evidence from per-entity-type analysis within Few-NERD ($n{=}8$, $\rho{=}{-}0.881$, $p{=}0.004$; entity types share model, tokenizer, and temperature, so effective degrees of freedom may be lower than 6).
docs/paper/sections/conclusion.tex:6:When either condition is violated, LP gains fall below detectable thresholds despite 12\textendash 14~pp oracle headroom: on SciERC (17.8\% degeneracy, $\rho{\approx}0.24$), LP yields $+0.61$~pp (below the ${\approx}$1.5~pp MDE at 80\% power); on CoNLL (59.1\% degeneracy), LP degrades selection ($-1.05$~pp).
docs/paper/sections/discussion.tex:31:The cross-dataset gradient (59\% $\to$ $-1.05$~pp, 18\% $\to$ $+0.61$~pp, 14\% $\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory) is consistent with an inverse relationship; per-entity-type analysis within Few-NERD ($\rho{=}{-}0.881$, $p{=}0.004$, $n{=}8$; entity types share model and tokenizer, effective $\mathit{df}$ may be lower; Appendix~\ref{app:per_type_lp}) provides supporting evidence.
docs/paper/sections/appendix.tex:804:  & Greedy        & 0.6182 & 0.6204 & $+$0.0022 \\
docs/paper/sections/appendix.tex:1027:1.0 & $+$13.3 & 0.360 & 0.205 & ${\approx}$0.39 & ${\approx}$0.612 \\
docs/paper/sections/appendix.tex:1151:VC & \textbf{.460} & .743 & 0.611 & $-$1.54\,pp \\
docs/paper/sections/appendix.tex:1152:SJ & .375 & .738 & \textbf{0.633} & $+$0.61\,pp \\
docs/paper/sections/appendix.tex:1165:Despite 13.63~pp of oracle headroom, no signal achieves significant selection improvement (best: SJ, $+0.61$~pp, $p{=}0.175$); VC, the strongest QE signal, yields the worst selection ($-1.54$~pp), consistent with the correlation-selection gap observed at larger scales.
docs/paper/sections/appendix.tex:1197:(4)~Low degeneracy (13.8\%) combined with strong LP-quality alignment ($\rho{\approx}0.5$) enables LP selection: candidates differ in F1 more often, and LP can rank them effectively. This contrasts with SciERC (17.8\% degeneracy but weak alignment $\rho{\approx}0.24$, LP $+0.61$~pp) and CoNLL (59.1\%, LP $-1.05$~pp).
docs/paper/sections/appendix.tex:1300:Within-instance LP-quality alignment is relatively stable under this convergence shift (mean $\rho$: $0.524 \to 0.407$; median $\rho$: $0.667 \to 0.615$), consistent with alignment being determined primarily by task structure rather than training duration.
docs/paper/sections/appendix.tex:1320:Within-inst.\ $\rho$ (median) & 0.667 & 0.615 \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "8fbd52c0-307e-4570-8850-c903c3b89b9c",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:80:Random           & $0.610 \\pm 0.003$ & --- \\\\\ndocs/paper/sections/experiments.tex:108:SciERC & 529 & .644 & 13.2\\,pp & 17.8\\% & .215 & $+$0.61\\,pp \\\\\ndocs/paper/sections/experiments.tex:120:The cross-dataset gradient is consistent with an inverse relationship (59.1\\% $\\to$ $-1.05$~pp, 17.8\\% $\\to$ $+0.61$~pp, 13.8\\% $\\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory given 5+ confounds; Figure~\\ref{fig:degeneracy_scatter}), with supporting evidence from per-entity-type analysis within Few-NERD ($n{=}8$, $\\rho{=}{-}0.881$, $p{=}0.004$; entity types share model, tokenizer, and temperature, so effective degrees of freedom may be lower than 6).\ndocs/paper/sections/conclusion.tex:6:When either condition is violated, LP gains fall below detectable thresholds despite 12\\textendash 14~pp oracle headroom: on SciERC (17.8\\% degeneracy, $\\rho{\\approx}0.24$), LP yields $+0.61$~pp (below the ${\\approx}$1.5~pp MDE at 80\\% power); on CoNLL (59.1\\% degeneracy), LP degrades selection ($-1.05$~pp).\ndocs/paper/sections/discussion.tex:31:The cross-dataset gradient (59\\% $\\to$ $-1.05$~pp, 18\\% $\\to$ $+0.61$~pp, 14\\% $\\to$ $+1.36$~pp; $n{=}3$ datasets, exploratory) is consistent with an inverse relationship; per-entity-type analysis within Few-NERD ($\\rho{=}{-}0.881$, $p{=}0.004$, $n{=}8$; entity types share model and tokenizer, effective $\\mathit{df}$ may be lower; Appendix~\\ref{app:per_type_lp}) provides supporting evidence.\ndocs/paper/sections/appendix.tex:804:  & Greedy        & 0.6182 & 0.6204 & $+$0.0022 \\\\\ndocs/paper/sections/appendix.tex:1027:1.0 & $+$13.3 & 0.360 & 0.205 & ${\\approx}$0.39 & ${\\approx}$0.612 \\\\\ndocs/paper/sections/appendix.tex:1151:VC & \\textbf{.460} & .743 & 0.611 & $-$1.54\\,pp \\\\\ndocs/paper/sections/appendix.tex:1152:SJ & .375 & .738 & \\textbf{0.633} & $+$0.61\\,pp \\\\\ndocs/paper/sections/appendix.tex:1165:Despite 13.63~pp of oracle headroom, no signal achieves significant selection improvement (best: SJ, $+0.61$~pp, $p{=}0.175$); VC, the strongest QE signal, yields the worst selection ($-1.54$~pp), consistent with the correlation-selection gap observed at larger scales.\ndocs/paper/sections/appendix.tex:1197:(4)~Low degeneracy (13.8\\%) combined with strong LP-quality alignment ($\\rho{\\approx}0.5$) enables LP selection: candidates differ in F1 more often, and LP can rank them effectively. This contrasts with SciERC (17.8\\% degeneracy but weak alignment $\\rho{\\approx}0.24$, LP $+0.61$~pp) and CoNLL (59.1\\%, LP $-1.05$~pp).\ndocs/paper/sections/appendix.tex:1300:Within-instance LP-quality alignment is relatively stable under this convergence shift (mean $\\rho$: $0.524 \\to 0.407$; median $\\rho$: $0.667 \\to 0.615$), consistent with alignment being determined primarily by task structure rather than training duration.\ndocs/paper/sections/appendix.tex:1320:Within-inst.\\ $\\rho$ (median) & 0.667 & 0.615 \\\\",
    "numLines": 13
  }
}
```

</details>

---

### Tool call

_source line 85_

<details open><summary>🔧 Tool call — Grep · `toolu_01AbESFiL1ZD4kWH9LgkW9uc`</summary>

```json
{
  "pattern": "\\\\+0\\.2[^0-9]",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "e8e20754-97fb-48a7-b513-9c88a048c148",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01USVtdmrW4qL9PSHSFg2n6J",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23443,
      "cache_read_input_tokens": 69317,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 23443
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

_source line 86 · 2026-05-18T05:47:20.117Z_

<details><summary>↩ Tool result · `toolu_01AbESFiL1ZD4kWH9LgkW9uc`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "09eb1d1a-26c9-411d-ad0d-f3373d145021",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Assistant

_source line 87_

<details><summary>Logged reasoning block</summary>

```text
Now let me carefully cross-reference all the quantitative claims across sections. Let me now compile a comprehensive audit.

Let me systematically go through the key claims.

### 1. Old Value Residuals (D131/D132)

| Old Value | Status |
|-----------|--------|
| 0.614 (SciERC greedy) | ✅ No matches found. All updated to 0.644/0.645 |
| 0.752 (SciERC oracle) | ✅ Only match is in tab:t_degeneracy (SJ mean at T=0.8). Different context. |


| 13.8pp (SciERC headroom) | ✅ No residual — all 13.8 matches are Few-NERD degeneracy (correct usage) |
| 0.205 (SciERC LP ρ in tab:fewnerd) | I need to double-check this one. The task mentions updating 0.205 to 0.215 for max_LP, and 0.215 only appears in tab:fewnerd. But 0.205 still shows up in tab:quality_estimation, which uses a different context. |

Actually, looking more carefully — tab:quality_estimation measures mean token LP while tab:fewnerd measures max token-level LP, so these are two separate metrics entirely. The 0.205 value is correct for mean LP, and 0.215 is correct for max LP. They're not contradictory, just measuring different things. I should verify there's no place where 0.205 is being cited when it should reference 0.215 instead.

Now checking the specific values: the +0.42pp SciERC LP improvement doesn't appear anywhere except as correlation coefficients on other datasets — the actual improvement in tab:fewnerd is +0.61pp, which is correct. The CoNLL degeneracy value has been updated from 47.4% to either 59.1% or 48.3% depending on the sample size. For LLaMA degeneracy, I'm still verifying the current value.

Moving into cross-section consistency, I'm comparing SciERC Greedy F1 scores across different tables: tab:selection reports 0.645 ± 0.001 as a 2-seed average, while tab:fewnerd shows 0.644 from a single seed with max-LP filtering applied. The footnote accounts for this discrepancy by explaining the methodological differences between the two evaluations.

Now I'm noticing some conflicting values in the appendix—experiments.tex claims the 3-seed mean is 0.644 and calls it consistent with tab:selection, but tab:selection actually shows 0.645, which creates a small inconsistency I need to resolve.

Looking more carefully, the difference is just 0.001, which falls within the reported error margins, so the "consistent with" language in the footnote is justified. The N-scaling footnote explains its lower value of 0.640 by pointing to seed and aggregation differences, which accounts for that discrepancy.

Now I'm checking the Oracle headroom values in tab:selection.

The greedy F1 of 0.645 gives an oracle headroom of 13.3 percentage points, and I'm verifying this matches across the other datasets and document sections—tab:fewnerd shows 13.2pp, and the various mentions in experiments.tex, conclusion.tex, abstract.tex, intro.tex all align with this 13pp range, including the 4B model's 13.0pp headroom.

Now I'm checking the SciERC LP improvements and noticing a discrepancy: tab:selection reports +0.2pp while tab:fewnerd shows +0.61pp, but conclusion.tex cites the +0.61pp figure—I need to figure out which evaluation setup that's coming from. I'm noticing a significant discrepancy between the two tables—tab:selection reports a +0.2pp improvement while tab:fewnerd shows +0.61pp for SciERC, and the footnote attributes this to differences in aggregation methods and single-seed versus multi-seed evaluation. The conclusion pulls from tab:fewnerd while the experiments section references tab:selection, which could be confusing without clearer explanation of why these values diverge so dramatically. The conclusion uses the gold-filtered evaluation framework, which explains the higher LP gains. There's potential ambiguity when readers see +0.61 pp in the conclusion but +0.2 pp in the selection table, though the footnote clarifies this distinction. Now I'm checking the Few-NERD LP gain citations across the paper — they consistently report +1.36 pp with statistical significance, which all align properly. I've verified the N-scaling gain is consistently reported as +0.52 pp across all sections. Now I'm checking the degeneracy range values—they're listed as 14–59% throughout the document, but when I look at the actual table data, the Few-NERD degeneracy appears to be 13.8%, which doesn't quite match the rounded range being cited. I'm verifying the degeneracy percentages match the abstract's "14–59%" range, which checks out when rounding 13.8% to 14% and 59.1% to 59%. Now I'm looking at the correlation and AUROC metrics across the paper—the abstract, intro, and conclusion all cite "ρ up to 0.42, AUROC up to 0.82," and I need to confirm these maximums against the quality estimation table.

The actual maximum ρ is 0.451 on CoNLL with the EM signal, and the maximum AUROC is 0.816 on the same dataset. The figure caption correctly reports "ρ up to 0.45 on CoNLL," but the abstract and intro understate this as "ρ up to 0.42" without specifying which dataset, which appears to be the Few-NERD value instead of the true maximum. I need to reconcile the discrepancy between what the abstract claims and what the data actually shows. Looking at the maximum ρ values across the main tables—SciERC peaks at 0.379, CoNLL reaches 0.451 with Qwen, and Few-NERD maxes out at 0.421—the abstract's claim of "ρ up to 0.42" appears to exclude the CoNLL results, which suggests it might be referring only to the primary test bed and Few-NERD rather than all reported values. So the overall max is 0.451 on CoNLL. "ρ up to 0.42" excludes the CoNLL values. 

But is the intent to report the maximum across all datasets or a representative value? The way it's written, "All signals achieve reliable quality estimation (ρ up to 0.42, AUROC up to 0.82)" seems to claim the maximum across the study is 0.42, but it's actually 0.451.

The Figure caption does say "ρ up to 0.45 on CoNLL" which is more accurate. So the Figure caption and the Abstract/Introduction/Conclusion are inconsistent on this point.

Now I'm checking whether this is actually a problem—the "ρ up to 0.42" might be intentionally excluding the ceiling-control dataset, but that's not explicitly stated anywhere. For AUROC, the 0.82 figure is a rounded version of 0.816 from the quality estimation table, which matches the Figure caption. However, I'm noticing the WNUT appendix shows an AUROC of 0.913, which is substantially higher than 0.82, though WNUT appears to be a signal-collapse boundary case where the full-set correlations behave differently.

Let me now look more carefully at the introduction figure caption to verify the exact claims being made.

The caption states "ρ up to 0.45 on CoNLL, 0.38 on the primary test bed, 0.42 on Few-NERD; AUROC up to 0.82" — checking these against the tables, the CoNLL max is 0.451 (rounds to 0.45), SciERC is 0.379 (rounds to 0.38), and Few-NERD is 0.421 (rounds to 0.42), so the caption is accurate. But there's an inconsistency: the abstract and introduction claim "ρ up to 0.42" while the figure caption includes the higher CoNLL value of 0.45, suggesting they may be deliberately excluding CoNLL as a ceiling-effect control, though this distinction isn't explicitly noted.

Now I'm verifying the LP ρ values across datasets more systematically — SciERC shows 0.205 consistently across the quality estimation table, robustness appendix, and main text, while Few-NERD has a slightly higher 0.215 under different filtering conditions. Looking at the Few-NERD results, LP ρ is consistently 0.421 across the table and appendix, with the main text rounding to 0.42. For VC on SciERC, the value 0.379 appears consistently across tables and text. Now checking the CoNLL degeneracy numbers—there's a discrepancy between the two tables: one shows 59.1% with N=8 (gold-filtered) while the other shows 48.3% with N=16, so the sample size difference explains the variation. I'm checking the citations for degeneracy values across the paper — the 59–86% range in discussion line 26 appears to mix Qwen's 59.1% with LLaMA's 86.4%, while line 10 correctly uses the N=8 gold-filtered values from 17.8% to 59.1%. Now I need to verify the SciERC LP selection metric discrepancy, where the table shows a difference of only +0.002 between LP and Greedy approaches.

I'm noticing the conclusion reports +0.61pp for SciERC LP improvement using the gold-filtered max-LP single-seed values, but the experiments section cites +0.2pp from the 2-seed mean approach — both are valid but the dual reporting could confuse readers, though it is footnoted. I should also check what the N-scaling table shows for SciERC LP at N=8 to see if there's consistency across these different evaluation setups.

Looking at the N-scaling analysis, there's actually a third value: +0.39pp, which uses gold-filtered evaluation with a different seed and aggregation method. So across the paper I'm seeing three distinct SciERC LP Δ measurements at N=8 — +0.2pp, +0.61pp, and +0.39pp — each stemming from different experimental configurations and properly documented in the footnotes.

Now checking the epoch confound values. The discussion claims degeneracy rises from 11% to 31% between 3 and 5 epochs while LP gains halve, and the table confirms this: degeneracy goes from 11.1% to 31.3%, with LP Δ dropping from +1.37pp to +0.62pp. That's roughly a 55% decline, which qualitatively matches "halving." For SciERC specifically, the 3-point curve shows degeneracy climbing from 6.4% to 47.8% across 3, 5, and 10 epochs, with within-instance alignment deteriorating as well.

Now I'm verifying the non-tied subset results. The discussion reports +2.9 pp with p=0.004, which appears consistently across the experiments section and the main table, with n=210 and ρ=0.39.

For the temperature ablation, T=1.2 shows 12.5% degeneracy and ρ=0.225 across multiple sections of the paper. I'm also checking the LoRA rank ablation where rank=8 reduces degeneracy from 17.8% to 7.2%. Now I'm checking the WNUT dataset values—the zero F1 rate and correlation metrics all line up with what's reported in the tables. Moving on to verify the figure citations.

I'm cross-referencing the correlation values claimed in the intro against the quality estimation table: CoNLL maxes out at 0.451, SciERC at 0.379, and Few-NERD at 0.421, all matching the rounded figures in the caption. But I'm noticing a discrepancy—the figure says "up to 0.45" while the abstract claims "up to 0.42," and the actual maximum across the study is higher than both.

Now checking the calibration baseline numbers: the SciERC Greedy value of 0.644 aligns with the supervised verifier footnote, though the table shows 0.645, which is a minor variation that likely comes from different seed counts. For the Few-NERD scaling results, I'm seeing the performance gains with reduced degeneracy and expanded headroom, while the LP ranking quality stays consistent.

But there's something off with the degeneracy numbers—the table shows 13.8% for Few-NERD at N=8, yet the scaling paragraph reports 14.6% for the same condition. This could be because the N-scaling evaluation uses a different subset where all 16 samples are available, or they might be using different random seeds, which would explain the discrepancy between the two reported values. I'm noticing two specific discrepancies between the table values and the N-scaling paragraph: degeneracy differs at 13.8% versus 14.6%, and headroom differs at 12.4pp versus 12.1pp. These gaps could stem from different random seeds, varying instance subsets between N=8 and N=16 experiments, or different sampling procedures, but they're worth documenting.

Now I'm seeing a third inconsistency—the 3-epoch Few-NERD model shows 11.1% degeneracy in one table but 13.8% in another, which initially seems contradictory until I realize they're working with different dataset sizes: one table uses 4,351 instances after filtering while the other uses the full 32,565, suggesting they're evaluating on different subsets of the data.

The core issue is that the same metrics appear across multiple tables with slightly different values, likely due to variations in evaluation splits, random seeds, or filtering criteria applied at different stages. Most of these discrepancies are explained through footnotes, but not all have explicit documentation.

Let me now pull together the final audit report with the key findings.

I've confirmed that all the old residual values from the earlier drafts have been completely removed—no trace of those outdated numbers anywhere. The 0.752 value in the appendix refers to something entirely different (SJ mean at T=0.8), so that's not a carryover. ✅

There's a genuine inconsistency with the correlation coefficient: the abstract, introduction, and conclusion all claim "ρ up to 0.42," but the actual maximum across the entire study is 0.451 from the CoNLL Qwen EM result. The figure caption does correctly state "ρ up to 0.45 on CoNLL," so there's a mismatch between the text claims and what the data actually shows. ⚠️

For the Few-NERD degeneracy at N=8, I'm seeing different percentages reported in different places—13.8% in one table, 14.6% in the N-scaling paragraph—and these variations stem from different subsets or filtering applied during analysis.

The Few-NERD headroom shows a minor gap between 12.4pp and 12.1pp depending on where I look. SciERC's LP improvement is reported as three separate values across different sections, all properly footnoted but creating some confusion about which number applies where. The greedy F1 scores for SciERC also vary depending on the seeding strategy and filtering method used.

Now I'm checking consistency across the paper for the per-entity-type correlation—the Spearman coefficient ρ=−0.881 with p=0.004 appears consistently across intro, experiments, discussion, and appendix sections. The degeneracy threshold of 15% is also holding steady across intro, conclusion, and discussion, though I'm still verifying the experiments section footnote.

For the LP compression statistics, I'm seeing the median range of 0.041 nats referenced in both discussion and appendix, with the 60.3% tied fraction at ε=0.05 matching across the table and appendix. The LP spread comparison between different LoRA ranks (0.057 vs 0.041 nats) also checks out. Now I need to verify the within-instance correlation between log probability and F1 score.

The pooled within-instance ρ(LP, F1) value of 0.248 appears consistently across the appendix, the main results table, and the intro mentions it as approximately 0.24 on SciERC, so that's aligned. But I'm noticing a potential issue with the figure caption—it claims ρ reaches up to 0.45 on CoNLL and 0.38 on the primary test bed, but when I check the quality estimation table, the maximum ρ values for CoNLL are 0.451 for Qwen on EM and 0.431 for LLaMA on SJ, which suggests the 0.45 figure is specifically the Qwen EM result.

Now I need to verify the Few-NERD claim about ρ≈0.5 alignment. The intro states that LP achieves +1.36 pp on Few-NERD when low instance degeneracy (13.8%) and adequate alignment (ρ≈0.5) are jointly met, but I don't see the within-instance ρ for Few-NERD directly reported in the main table—I'll need to check the appendix epoch confound table to confirm this alignment value.

Now I'm checking the free-form RE results across the documents. The discussion mentions +2.35 pp, but the appendix shows +1.84±0.12 pp with individual seed runs ranging from +1.69 to +2.00 pp, so there's a discrepancy I need to reconcile before finalizing the audit. I'm noticing a discrepancy between the reported +2.35pp in the discussion and the values I'm seeing in the appendix—the 4-seed mean shows +1.84±0.12pp, and the seed 42 result is +1.69pp. Let me trace where the +2.35pp figure actually comes from by checking if it's calculated differently or from a separate evaluation. There's a discrepancy between the reported +2.35pp in the discussion and the actual empirical results showing +1.69pp or +1.84±0.12pp across seeds. Let me look more carefully at the appendix to see if this +2.35pp comes from a different model size or configuration, or if it's perhaps an older calculation that doesn't match the current data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "f1def396-f8cc-45ee-a01e-60ba682d2ba7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012yYQz2UcAVaRn5vu3cbQMw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3452,
      "cache_read_input_tokens": 92760,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3452
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

_source line 88_

搜索一些额外的数值来完成交叉检查。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "6f8a7646-2a21-4578-ac1c-0031d4c9dfd8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012yYQz2UcAVaRn5vu3cbQMw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3452,
      "cache_read_input_tokens": 92760,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3452
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

_source line 89_

<details open><summary>🔧 Tool call — Grep · `toolu_01WEfksoPyFe6bQsQksZVWTu`</summary>

```json
{
  "pattern": "2\\.35",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "81a42208-7872-4a61-a303-64f6a83587c1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012yYQz2UcAVaRn5vu3cbQMw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3452,
      "cache_read_input_tokens": 92760,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3452
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

_source line 90 · 2026-05-18T05:50:51.740Z_

<details><summary>↩ Tool result · `toolu_01WEfksoPyFe6bQsQksZVWTu`</summary>

```text
docs/paper/sections/discussion.tex:21:Free-form decoding rules out constraint-imposed mechanisms for NER (std ratio 0.97; Appendix~\ref{app:freeform_ablation}) but restores LP selection for RE ($+2.35$~pp, $p{=}0.025$; Appendix~\ref{app:re_extension}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "18fd48c2-5d5d-406e-971b-d28140c1f79b",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/discussion.tex:21:Free-form decoding rules out constraint-imposed mechanisms for NER (std ratio 0.97; Appendix~\\ref{app:freeform_ablation}) but restores LP selection for RE ($+2.35$~pp, $p{=}0.025$; Appendix~\\ref{app:re_extension}).",
    "numLines": 1
  }
}
```

</details>

---

### Tool call

_source line 91_

<details open><summary>🔧 Tool call — Grep · `toolu_014hWPoJjnxBN6zFemh3NMLv`</summary>

```json
{
  "pattern": "14\\.6",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "dc0a2f18-12d1-4a47-9a70-3b3403a40abf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012yYQz2UcAVaRn5vu3cbQMw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3452,
      "cache_read_input_tokens": 92760,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3452
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

_source line 92 · 2026-05-18T05:50:52.535Z_

<details><summary>↩ Tool result · `toolu_014hWPoJjnxBN6zFemh3NMLv`</summary>

```text
docs/paper/sections/experiments.tex:135:Doubling $N$ from 8 to 16 on Few-NERD yields $+0.52$~pp (paired $p{=}0.003$, CI $[+0.17, +0.87]$), driven by reduced degeneracy (14.6\% $\to$ 7.0\%) expanding headroom (12.1 $\to$ 15.4~pp), while LP ranking quality remains stable ($\rho{\approx}0.62$).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "923eb4c6-995c-42a9-a6b8-3c4b7f2b1271",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:135:Doubling $N$ from 8 to 16 on Few-NERD yields $+0.52$~pp (paired $p{=}0.003$, CI $[+0.17, +0.87]$), driven by reduced degeneracy (14.6\\% $\\to$ 7.0\\%) expanding headroom (12.1 $\\to$ 15.4~pp), while LP ranking quality remains stable ($\\rho{\\approx}0.62$).",
    "numLines": 1
  }
}
```

</details>

---

### Tool call

_source line 93_

<details open><summary>🔧 Tool call — Grep · `toolu_017x7N1mpc5LmmDH6S3xSk7j`</summary>

```json
{
  "pattern": "0\\.45",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "a8cefac8-e9f9-4e20-a70d-6023ba6d3870",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012yYQz2UcAVaRn5vu3cbQMw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3452,
      "cache_read_input_tokens": 92760,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3452
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

_source line 94 · 2026-05-18T05:50:53.537Z_

<details><summary>↩ Tool result · `toolu_017x7N1mpc5LmmDH6S3xSk7j`</summary>

```text
docs/paper/sections/appendix.tex:92:[Omitted long matching line]
docs/paper/sections/appendix.tex:280:VC & +0.379 & [+0.299, +0.456] \\
docs/paper/sections/appendix.tex:880:Fail 2+ seeds & 26 & 2.46 & 0.774 & $-$0.450 \\
docs/paper/sections/appendix.tex:1026:0.8 & $+$10.5 & 0.359 & 0.253 & 0.451 & 0.622 \\
docs/paper/sections/introduction.tex:20:\caption{The correlation-selection gap. \textbf{Left}: consistency signals reliably predict instance-level quality ($\rho$ up to 0.45 on CoNLL, 0.38 on the primary test bed, 0.42 on Few-NERD; AUROC up to 0.82). \textbf{Right}: quality estimation does not translate to selection; all methods approximately match greedy decoding ($T{=}0$) despite 13~pp oracle headroom (\S\ref{sec:discussion}).}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "a2e47e2f-3ae3-42e1-a55c-3cae398493ca",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/appendix.tex:92:[Omitted long matching line]\ndocs/paper/sections/appendix.tex:280:VC & +0.379 & [+0.299, +0.456] \\\\\ndocs/paper/sections/appendix.tex:880:Fail 2+ seeds & 26 & 2.46 & 0.774 & $-$0.450 \\\\\ndocs/paper/sections/appendix.tex:1026:0.8 & $+$10.5 & 0.359 & 0.253 & 0.451 & 0.622 \\\\\ndocs/paper/sections/introduction.tex:20:\\caption{The correlation-selection gap. \\textbf{Left}: consistency signals reliably predict instance-level quality ($\\rho$ up to 0.45 on CoNLL, 0.38 on the primary test bed, 0.42 on Few-NERD; AUROC up to 0.82). \\textbf{Right}: quality estimation does not translate to selection; all methods approximately match greedy decoding ($T{=}0$) despite 13~pp oracle headroom (\\S\\ref{sec:discussion}).}",
    "numLines": 5
  }
}
```

</details>

---

### Tool call

_source line 95_

<details open><summary>🔧 Tool call — Grep · `toolu_015nGo1GDG6i57YzoYVsViu7`</summary>

```json
{
  "pattern": "12\\.1",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "119d160c-a20f-4d24-8694-c1bcbce3b5d6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012yYQz2UcAVaRn5vu3cbQMw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3452,
      "cache_read_input_tokens": 92760,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3452
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

_source line 96 · 2026-05-18T05:50:54.479Z_

<details><summary>↩ Tool result · `toolu_015nGo1GDG6i57YzoYVsViu7`</summary>

```text
docs/paper/sections/experiments.tex:135:Doubling $N$ from 8 to 16 on Few-NERD yields $+0.52$~pp (paired $p{=}0.003$, CI $[+0.17, +0.87]$), driven by reduced degeneracy (14.6\% $\to$ 7.0\%) expanding headroom (12.1 $\to$ 15.4~pp), while LP ranking quality remains stable ($\rho{\approx}0.62$).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "c941cfcc-bff9-4c1d-9f4d-3c04d72168eb",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:135:Doubling $N$ from 8 to 16 on Few-NERD yields $+0.52$~pp (paired $p{=}0.003$, CI $[+0.17, +0.87]$), driven by reduced degeneracy (14.6\\% $\\to$ 7.0\\%) expanding headroom (12.1 $\\to$ 15.4~pp), while LP ranking quality remains stable ($\\rho{\\approx}0.62$).",
    "numLines": 1
  }
}
```

</details>

---

### Tool call

_source line 97_

<details open><summary>🔧 Tool call — Grep · `toolu_01MYVx2w29MpPSnvS4iFWwKM`</summary>

```json
{
  "pattern": "0\\.39[^0-9]",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "6110620d-7b94-45a1-bd1f-8f0f3e3785dd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012yYQz2UcAVaRn5vu3cbQMw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3452,
      "cache_read_input_tokens": 92760,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3452
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

_source line 98 · 2026-05-18T05:50:55.207Z_

<details><summary>↩ Tool result · `toolu_01MYVx2w29MpPSnvS4iFWwKM`</summary>

```text
docs/paper/sections/experiments.tex:123:All five signals achieve positive QE on Few-NERD (LP $\rho{=}0.42$, VC $0.39$), yet only LP translates QE into selection; the gap confirms that strong instance-level QE cannot rank candidates within an instance.
docs/paper/sections/discussion.tex:15:Where compression is mitigated (LP range ${\geq}0.05$, $n{=}210$), within-instance $\rho$ rises to 0.39 and LP selection yields $+2.9$~pp ($p{=}0.004$, survives Bonferroni; Table~\ref{tab:nontied_main}).
docs/paper/sections/appendix.tex:556:Among instances with LP range ${\geq}0.05$ ($n{=}210$, 40\% of total), log-probability selection \textit{significantly} outperforms single-sample ($+2.9$~pp F1, $p{=}0.004$), and within-instance $\rho(\text{LP}, \text{F1})$ rises from 0.08 (tied subset) to 0.39 (non-tied subset).
docs/paper/sections/appendix.tex:624:Non-tied (range ${\geq}0.05$) & 210 & 0.39 & $+$2.9~pp ($p{=}0.004$) \\
docs/paper/sections/appendix.tex:963:LP selection improves monotonically with $N$ ($+0.39$~pp at $N{=}8$ to $+0.95$~pp at $N{=}32$), but even at $N{=}32$, where degeneracy falls to 4\% and oracle headroom reaches ${\sim}20$~pp, the best signal captures less than 5\% of the available improvement.
docs/paper/sections/appendix.tex:978:8 & 11.0\% & $+$14.5 & $+$0.39 & $+$0.20 & $+$0.15 & $-$0.77 & $-$2.87 & $+$0.39 \\
docs/paper/sections/appendix.tex:1027:1.0 & $+$13.3 & 0.360 & 0.205 & ${\approx}$0.39 & ${\approx}$0.612 \\
docs/paper/sections/appendix.tex:1194:(1)~All five signals achieve positive QE ($\rho$ 0.29--0.42); quality estimation works on Few-NERD. LP leads ($\rho{=}0.42$), followed by VC ($0.39$); the ranking differs from SciERC where VC leads, consistent with dataset-specific signal informativeness.
docs/paper/sections/appendix.tex:1273:Platt scaling substantially improves probability calibration (ECE drops from 0.26--0.39 to 0.01--0.08), but better-calibrated probabilities do not translate to better selection.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "bf54e4a5-a87b-494b-bdda-d94032b46150",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:123:All five signals achieve positive QE on Few-NERD (LP $\\rho{=}0.42$, VC $0.39$), yet only LP translates QE into selection; the gap confirms that strong instance-level QE cannot rank candidates within an instance.\ndocs/paper/sections/discussion.tex:15:Where compression is mitigated (LP range ${\\geq}0.05$, $n{=}210$), within-instance $\\rho$ rises to 0.39 and LP selection yields $+2.9$~pp ($p{=}0.004$, survives Bonferroni; Table~\\ref{tab:nontied_main}).\ndocs/paper/sections/appendix.tex:556:Among instances with LP range ${\\geq}0.05$ ($n{=}210$, 40\\% of total), log-probability selection \\textit{significantly} outperforms single-sample ($+2.9$~pp F1, $p{=}0.004$), and within-instance $\\rho(\\text{LP}, \\text{F1})$ rises from 0.08 (tied subset) to 0.39 (non-tied subset).\ndocs/paper/sections/appendix.tex:624:Non-tied (range ${\\geq}0.05$) & 210 & 0.39 & $+$2.9~pp ($p{=}0.004$) \\\\\ndocs/paper/sections/appendix.tex:963:LP selection improves monotonically with $N$ ($+0.39$~pp at $N{=}8$ to $+0.95$~pp at $N{=}32$), but even at $N{=}32$, where degeneracy falls to 4\\% and oracle headroom reaches ${\\sim}20$~pp, the best signal captures less than 5\\% of the available improvement.\ndocs/paper/sections/appendix.tex:978:8 & 11.0\\% & $+$14.5 & $+$0.39 & $+$0.20 & $+$0.15 & $-$0.77 & $-$2.87 & $+$0.39 \\\\\ndocs/paper/sections/appendix.tex:1027:1.0 & $+$13.3 & 0.360 & 0.205 & ${\\approx}$0.39 & ${\\approx}$0.612 \\\\\ndocs/paper/sections/appendix.tex:1194:(1)~All five signals achieve positive QE ($\\rho$ 0.29--0.42); quality estimation works on Few-NERD. LP leads ($\\rho{=}0.42$), followed by VC ($0.39$); the ranking differs from SciERC where VC leads, consistent with dataset-specific signal informativeness.\ndocs/paper/sections/appendix.tex:1273:Platt scaling substantially improves probability calibration (ECE drops from 0.26--0.39 to 0.01--0.08), but better-calibrated probabilities do not translate to better selection.",
    "numLines": 9
  }
}
```

</details>

---

### Assistant

_source line 99_

<details><summary>Logged reasoning block</summary>

```text
OK, so the +2.35pp for RE free-form LP selection in discussion.tex:21 only appears once. The appendix says +1.84±0.12pp (4-seed mean) or +1.69pp (seed 42). Let me check if +2.35 could be from a different calculation.

Looking at the free-form ablation Panel B:
- RE constrained: LP-selected 0.2845, Greedy 0.2913, gap = -0.0068 = -0.68pp


- RE free-form: LP-selected 0.3050, Greedy 0.2880, gap = +0.0169 = +1.69pp

I'm testing whether +2.35 could be the difference between the free-form and constrained LP selection gaps: +1.69 - (-0.68) = +2.37pp, which is close but not exact. Or maybe it's the improvement from constrained to free-form LP selection: 0.3050 - 0.2845 = +2.05pp, which also doesn't match.

Let me check the appendix for where this +2.35 figure comes from. The discussion references "Appendix app:re_extension" for this claim, and when I look at the RE extension section, it states +1.8±0.1pp for free-form RE LP selection across 4 seeds, but the discussion claims +2.35pp—these numbers don't align.

I'm wondering if the +2.35 might represent the swing between constrained and free-form decoding (+1.84 minus -0.9 equals +2.74), but that's still off. Or perhaps Panel B is using gold-filtered evaluation while the appendix uses the full set, which could explain the discrepancy. Looking at Panel B's metrics more closely, the NER and RE greedy scores seem to match gold-filtered results, but I need to verify this against the full-set numbers in the table.

The p-value of 0.025 also doesn't align with any p-values I've found for free-form RE LP selection in the appendix. The appendix actually reports a different effect size (Δ=+0.7 pp, p=0.058) for the N=16 configuration. It seems like there's a genuine inconsistency here—the discussion claims +2.35pp with p=0.025, but the supporting tables show either +1.84±0.12pp as a 4-seed mean or +1.69pp depending on the seed, neither of which matches the cited figure.

Now checking the 14.6% for Few-NERD at N=8 mentioned in the N-scaling section—it only appears once in the experiments file, but the table shows 13.8% for that same condition. The discrepancy might stem from different evaluation subsets or seeds. I'm also noticing a small gap between the 12.1 pp and 12.4 pp headroom values, likely from the same source. Let me also verify the SciERC LP effect size cited in the conclusion.

The conclusion references +0.61 pp for SciERC LP, which matches the table value, but the introduction cites +0.2 pp from a different evaluation protocol. Both numbers are valid and properly footnoted, but they could confuse readers since they're both about the same metric under different conditions. I need to check if the conclusion is being clear about which protocol it's referencing. The footnote does clarify the discrepancy, so that's acceptable. Now I'm verifying the EM AUROC value—the table shows 0.816 for CoNLL Qwen, which rounds correctly to 0.82 at two decimal places. Let me finalize the audit report with all findings.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "db58d2dd-2215-40ee-8853-bc89ce30385a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vszr5YAqEWnQWhjiyD72uJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13881,
      "cache_read_input_tokens": 96212,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13881
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

_source line 100_

全部数据已收集完毕。以下是完整审计报告。

---

## 审计结果

### 旧值残留检查（D131/D132）

| 旧值 | 搜索结果 | 状态 |
|------|---------|------|
| 0.614 (SciERC greedy) | 全文无匹配 | ✅ 已全部更新为 0.644/0.645 |
| 0.752 (SciERC oracle) | 仅 `appendix.tex:1057` | ✅ 该处是 tab:t_degeneracy 中 T=0.8 的 SJ mean 值，非 SciERC oracle |
| 13.8pp (SciERC headroom) | 无残留 | ✅ 所有 13.8 均指 Few-NERD degeneracy（正确用法） |
| 0.205 (旧 SciERC LP ρ) | 多处匹配 | ✅ 0.205 是 tab:quality_estimation 中 mean-LP 的正确值；tab:fewnerd 中 max-LP 为 0.215，两者是不同指标 |
| +0.42pp (旧 SciERC LP Δ) | 无残留 | ✅ 所有 0.42 均为 ρ 值，非 LP Δ |
| 47.4% (旧 CoNLL degen) | 全文无匹配 | ✅ 已更新为 59.1% (N=8) / 48.3% (N=16) |
| 89.2% (旧 LLaMA degen) | 全文无匹配 | ✅ 已更新为 86.4% |
| -0.07pp (旧 Table 3 LP Δ) | 全文无匹配 | ✅ 已废弃 |

**结论：所有 D131/D132 旧值均已清除。**

---

### 跨章节一致性

| 数值 | 出现位置 | 一致? | 说明 |
|------|---------|-------|------|
| ρ "up to 0.42" | abstract:4, intro:12, intro:30, conclusion:4 | ⚠️ | 实际最大 ρ=0.451 (CoNLL Qwen EM)。Figure caption 正确写 "ρ up to 0.45 on CoNLL"，但 Abstract/Intro/Conclusion 都写 "up to 0.42" |
| AUROC "up to 0.82" | abstract:4, intro:12, intro:20, conclusion:4 | ✅ | 0.816 四舍五入至 0.82 |
| +1.36pp Few-NERD | abstract:5, intro:13/38, exp:91/109/117, disc:5, conc:5, app:1182 | ✅ | 全部一致 |
| +0.52pp N-scaling | intro:13/38, exp:135, disc:16, conc:5 | ✅ | 全部一致 |
| 14–59% degeneracy | abstract:7, intro:15/34, conc:7 | ✅ | 13.8%≈14%, 59.1%≈59% |
| SciERC oracle 0.778 | exp:68 (tab:selection), exp:89 | ✅ | tab:fewnerd implied oracle=0.776, footnote已解释差异 |
| SciERC greedy 0.645 vs 0.644 | exp:69 (tab:selection: 0.645), exp:108 (tab:fewnerd: 0.644), exp:173 fn (0.644 3-seed mean), app:984 fn (0.640 N-scaling) | ✅ | 三处差异均有 footnote 解释 |
| ρ=−0.881, p=0.004, n=8 | intro:39, exp:120, disc:31, app:1203 | ✅ | |
| Non-tied +2.9pp, p=0.004 | exp:92, disc:15, app:556, app:624 | ✅ | |
| Within-inst ρ=0.248 | disc:12, app:557, app:626 | ✅ | intro:34 写 "ρ≈0.24" 是四舍五入 |
| T=1.2 degeneracy 12.5%, ρ=0.225 | intro:35, disc:28/29, app:1044/1059 | ✅ | |
| LoRA rank=8: degen 7.2%, ρ≈0.24 | exp:168, disc:30, related:23 | ✅ | |

---

### 发现的不一致

#### 1. ⚠️ "ρ up to 0.42" 低于实际最大值
- **位置**: abstract:4, intro:12, intro:30, conclusion:4
- **问题**: 全文多处声称 "ρ up to 0.42"，但 tab:quality_estimation 中 CoNLL Qwen EM ρ=0.451。Figure caption (intro:20) 正确写 "ρ up to 0.45 on CoNLL"
- **影响**: 低报了最大 ρ 值；与 Figure caption 不一致

#### 2. ⚠️ RE free-form LP gain: discussion 引用 +2.35pp，appendix 数据不匹配
- **位置**: discussion:21 写 "+2.35 pp, p=0.025"
- **Appendix 数据**: 
  - app:771: 4-seed mean = +1.84±0.12pp (seeds: +1.69, +1.76, +2.00, +1.91)
  - app:687 (RE extension): "+1.8±0.1 pp across 4 seeds"
  - app:810 (Panel B, seed=42): +1.69pp
- **问题**: +2.35pp 不匹配 appendix 中任何数值。最接近的是 constrained→free-form 的 swing (+1.69−(−0.68)=+2.37)，但这是方向变化量，不是 selection gain over greedy
- **影响**: 可能是过时数值或计算错误

#### 3. ⚠️ Few-NERD N=8 degeneracy: 14.6% vs 13.8%
- **位置**: experiments:135 写 "14.6% → 7.0%"（N=8→16 scaling）
- **Tab:fewnerd** (experiments:109): 13.8%
- **Tab:fewnerd_full** (appendix:1171): 13.8%
- **问题**: N-scaling 段引用 14.6%，但 tab:fewnerd 和 tab:fewnerd_full 均为 13.8%。可能是不同 subset/seed 导致，但缺少解释
- **影响**: 轻微数值不一致

#### 4. ⚠️ Few-NERD N=8 headroom: 12.1pp vs 12.4pp
- **位置**: experiments:135 写 "12.1 → 15.4 pp"（N=8→16）
- **Tab:fewnerd** (experiments:109): 12.4pp
- **问题**: 同上，可能是不同 subset/seed。差异 0.3pp
- **影响**: 轻微

#### 5. ⚠️（已知，非错误）SciERC LP Δ 三个不同值
- **+0.2pp**: tab:selection (2-seed mean, mean-LP) — experiments:89
- **+0.61pp**: tab:fewnerd (gold-filtered, max-LP, single-seed) — experiments:108, conclusion:6
- **+0.39pp**: N-scaling table (gold-filtered, seed=42) — appendix:978
- **状态**: 所有差异已有 footnote 解释。但 conclusion 使用 +0.61pp 而 introduction 使用 +0.2pp，可能造成读者困惑

---

### 未找到来源的 Claims

| Claim | 位置 | 说明 |
|-------|------|------|
| RE free-form +2.35pp, p=0.025 | discussion:21 | Appendix 数据（+1.84±0.12pp 4-seed mean, +1.69pp seed=42）均不匹配此值 |

---

### 总结

- **旧值残留**: 0 处。D131/D132 修正已完全传播。✅
- **发现的不一致**: 5 处
  - **需修改 (2)**:
    1. `discussion.tex:21` — RE free-form LP gain "+2.35pp" 与 appendix 数据不匹配，需核实数据源并修正
    2. `abstract.tex:4`, `intro.tex:12`, `intro.tex:30`, `conclusion.tex:4` — "ρ up to 0.42" 应改为 "ρ up to 0.45" 以匹配 Figure caption 和 tab:quality_estimation 实际最大值，或加限定语（如 "ρ up to 0.42 on the primary and cross-dataset test beds"）
  - **建议核实 (2)**: Few-NERD N-scaling 段中的 14.6%/12.1pp 与 tab:fewnerd 的 13.8%/12.4pp 不一致（可能是不同 evaluation subset，建议加 footnote 说明）
  - **已知差异 (1)**: SciERC LP Δ 在不同表格中有三个值（+0.2/+0.61/+0.39pp），已有 footnote 解释

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "uuid": "797438c4-1074-4f10-aa18-4c445ec37d3f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vszr5YAqEWnQWhjiyD72uJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13881,
      "cache_read_input_tokens": 96212,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13881
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

### Task result

_source line 101_

全部数据已收集完毕。以下是完整审计报告。

---

## 审计结果

### 旧值残留检查（D131/D132）

| 旧值 | 搜索结果 | 状态 |
|------|---------|------|
| 0.614 (SciERC greedy) | 全文无匹配 | ✅ 已全部更新为 0.644/0.645 |
| 0.752 (SciERC oracle) | 仅 `appendix.tex:1057` | ✅ 该处是 tab:t_degeneracy 中 T=0.8 的 SJ mean 值，非 SciERC oracle |
| 13.8pp (SciERC headroom) | 无残留 | ✅ 所有 13.8 均指 Few-NERD degeneracy（正确用法） |
| 0.205 (旧 SciERC LP ρ) | 多处匹配 | ✅ 0.205 是 tab:quality_estimation 中 mean-LP 的正确值；tab:fewnerd 中 max-LP 为 0.215，两者是不同指标 |
| +0.42pp (旧 SciERC LP Δ) | 无残留 | ✅ 所有 0.42 均为 ρ 值，非 LP Δ |
| 47.4% (旧 CoNLL degen) | 全文无匹配 | ✅ 已更新为 59.1% (N=8) / 48.3% (N=16) |
| 89.2% (旧 LLaMA degen) | 全文无匹配 | ✅ 已更新为 86.4% |
| -0.07pp (旧 Table 3 LP Δ) | 全文无匹配 | ✅ 已废弃 |

**结论：所有 D131/D132 旧值均已清除。**

---

### 跨章节一致性

| 数值 | 出现位置 | 一致? | 说明 |
|------|---------|-------|------|
| ρ "up to 0.42" | abstract:4, intro:12, intro:30, conclusion:4 | ⚠️ | 实际最大 ρ=0.451 (CoNLL Qwen EM)。Figure caption 正确写 "ρ up to 0.45 on CoNLL"，但 Abstract/Intro/Conclusion 都写 "up to 0.42" |
| AUROC "up to 0.82" | abstract:4, intro:12, intro:20, conclusion:4 | ✅ | 0.816 四舍五入至 0.82 |
| +1.36pp Few-NERD | abstract:5, intro:13/38, exp:91/109/117, disc:5, conc:5, app:1182 | ✅ | 全部一致 |
| +0.52pp N-scaling | intro:13/38, exp:135, disc:16, conc:5 | ✅ | 全部一致 |
| 14–59% degeneracy | abstract:7, intro:15/34, conc:7 | ✅ | 13.8%≈14%, 59.1%≈59% |
| SciERC oracle 0.778 | exp:68 (tab:selection), exp:89 | ✅ | tab:fewnerd implied oracle=0.776, footnote已解释差异 |
| SciERC greedy 0.645 vs 0.644 | exp:69 (tab:selection: 0.645), exp:108 (tab:fewnerd: 0.644), exp:173 fn (0.644 3-seed mean), app:984 fn (0.640 N-scaling) | ✅ | 三处差异均有 footnote 解释 |
| ρ=−0.881, p=0.004, n=8 | intro:39, exp:120, disc:31, app:1203 | ✅ | |
| Non-tied +2.9pp, p=0.004 | exp:92, disc:15, app:556, app:624 | ✅ | |
| Within-inst ρ=0.248 | disc:12, app:557, app:626 | ✅ | intro:34 写 "ρ≈0.24" 是四舍五入 |
| T=1.2 degeneracy 12.5%, ρ=0.225 | intro:35, disc:28/29, app:1044/1059 | ✅ | |
| LoRA rank=8: degen 7.2%, ρ≈0.24 | exp:168, disc:30, related:23 | ✅ | |

---

### 发现的不一致

#### 1. ⚠️ "ρ up to 0.42" 低于实际最大值
- **位置**: abstract:4, intro:12, intro:30, conclusion:4
- **问题**: 全文多处声称 "ρ up to 0.42"，但 tab:quality_estimation 中 CoNLL Qwen EM ρ=0.451。Figure caption (intro:20) 正确写 "ρ up to 0.45 on CoNLL"
- **影响**: 低报了最大 ρ 值；与 Figure caption 不一致

#### 2. ⚠️ RE free-form LP gain: discussion 引用 +2.35pp，appendix 数据不匹配
- **位置**: discussion:21 写 "+2.35 pp, p=0.025"
- **Appendix 数据**: 
  - app:771: 4-seed mean = +1.84±0.12pp (seeds: +1.69, +1.76, +2.00, +1.91)
  - app:687 (RE extension): "+1.8±0.1 pp across 4 seeds"
  - app:810 (Panel B, seed=42): +1.69pp
- **问题**: +2.35pp 不匹配 appendix 中任何数值。最接近的是 constrained→free-form 的 swing (+1.69−(−0.68)=+2.37)，但这是方向变化量，不是 selection gain over greedy
- **影响**: 可能是过时数值或计算错误

#### 3. ⚠️ Few-NERD N=8 degeneracy: 14.6% vs 13.8%
- **位置**: experiments:135 写 "14.6% → 7.0%"（N=8→16 scaling）
- **Tab:fewnerd** (experiments:109): 13.8%
- **Tab:fewnerd_full** (appendix:1171): 13.8%
- **问题**: N-scaling 段引用 14.6%，但 tab:fewnerd 和 tab:fewnerd_full 均为 13.8%。可能是不同 subset/seed 导致，但缺少解释
- **影响**: 轻微数值不一致

#### 4. ⚠️ Few-NERD N=8 headroom: 12.1pp vs 12.4pp
- **位置**: experiments:135 写 "12.1 → 15.4 pp"（N=8→16）
- **Tab:fewnerd** (experiments:109): 12.4pp
- **问题**: 同上，可能是不同 subset/seed。差异 0.3pp
- **影响**: 轻微

#### 5. ⚠️（已知，非错误）SciERC LP Δ 三个不同值
- **+0.2pp**: tab:selection (2-seed mean, mean-LP) — experiments:89
- **+0.61pp**: tab:fewnerd (gold-filtered, max-LP, single-seed) — experiments:108, conclusion:6
- **+0.39pp**: N-scaling table (gold-filtered, seed=42) — appendix:978
- **状态**: 所有差异已有 footnote 解释。但 conclusion 使用 +0.61pp 而 introduction 使用 +0.2pp，可能造成读者困惑

---

### 未找到来源的 Claims

| Claim | 位置 | 说明 |
|-------|------|------|
| RE free-form +2.35pp, p=0.025 | discussion:21 | Appendix 数据（+1.84±0.12pp 4-seed mean, +1.69pp seed=42）均不匹配此值 |

---

### 总结

- **旧值残留**: 0 处。D131/D132 修正已完全传播。✅
- **发现的不一致**: 5 处
  - **需修改 (2)**:
    1. `discussion.tex:21` — RE free-form LP gain "+2.35pp" 与 appendix 数据不匹配，需核实数据源并修正
    2. `abstract.tex:4`, `intro.tex:12`, `intro.tex:30`, `conclusion.tex:4` — "ρ up to 0.42" 应改为 "ρ up to 0.45" 以匹配 Figure caption 和 tab:quality_estimation 实际最大值，或加限定语（如 "ρ up to 0.42 on the primary and cross-dataset test beds"）
  - **建议核实 (2)**: Few-NERD N-scaling 段中的 14.6%/12.1pp 与 tab:fewnerd 的 13.8%/12.4pp 不一致（可能是不同 evaluation subset，建议加 footnote 说明）
  - **已知差异 (1)**: SciERC LP Δ 在不同表格中有三个值（+0.2/+0.61/+0.39pp），已有 footnote 解释

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 414297,
  "duration_api_ms": 415140,
  "num_turns": 42,
  "stop_reason": "end_turn",
  "session_id": "43b86651-9ba8-4861-8ff1-6ff5bfaa6230",
  "total_cost_usd": 1.417021,
  "usage": {
    "input_tokens": 626,
    "cache_creation_input_tokens": 98252,
    "cache_read_input_tokens": 426096,
    "output_tokens": 23384,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 98252,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 4500,
        "cache_read_input_tokens": 96212,
        "cache_creation_input_tokens": 13881,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 13881
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2093,
      "outputTokens": 15,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.002168,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 626,
      "outputTokens": 23384,
      "cacheReadInputTokens": 426096,
      "cacheCreationInputTokens": 98252,
      "webSearchRequests": 0,
      "costUSD": 1.414853,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "234f29de-024b-40e8-a961-0759c0af3283"
}
```

</details>

---
