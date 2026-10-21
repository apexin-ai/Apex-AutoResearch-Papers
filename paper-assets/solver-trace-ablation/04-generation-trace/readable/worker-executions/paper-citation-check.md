# paper citation check

**Observe but Don’t Optimize: Structural Rewards Trigger Goodhart Effects in Neurosymbolic Reasoning** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 30
- **Recorded user turns:** 0
- **Tool calls:** 9
- **Original source:** `logs/workers/worker_paper_citation-check_20260515T060148.log`
- **Structured JSON:** [`5e718fafa82467d2f601.json`](../../sessions/5e/5e718fafa82467d2f601.json)

## Before a recorded user message

30 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
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
  "uuid": "28a0d68e-d7b8-47ec-a4cb-dbd42a10ee35",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/memory/"
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
    "resetsAt": 1779336000,
    "rateLimitType": "seven_day",
    "utilization": 0.51,
    "isUsingOverage": false
  },
  "uuid": "f2a48ff1-2583-4460-bccd-77b59043d8d8",
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me start by checking the bib file and related work files to see what already exists.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "64965936-e8b0-4315-ae72-1ace4410fde9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MU3CwpvoAWce86B8SEhMhA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12964,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12964
      },
      "output_tokens": 44,
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

检查 bib 文件和 Related Work 中的引用情况。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "28491bb1-bcd5-466a-8ce2-5a104dacd554",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MU3CwpvoAWce86B8SEhMhA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12964,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12964
      },
      "output_tokens": 44,
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

<details open><summary>🔧 Tool call — Glob · `toolu_01FiMLLvEhn813v168pC5Rmf`</summary>

```json
{
  "pattern": "**/references.bib",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "9c961f91-29c6-4487-90d4-d3a4c7f996c8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MU3CwpvoAWce86B8SEhMhA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12964,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12964
      },
      "output_tokens": 44,
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

_source line 7 · 2026-05-15T06:01:59.496Z_

<details><summary>↩ Tool result · `toolu_01FiMLLvEhn813v168pC5Rmf`</summary>

```text
artifacts/_project/paper/references.bib
docs/paper/references.bib
paper/references.bib
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "326963ae-cb17-4862-bd71-2845fd949c77",
  "tool_use_result": {
    "filenames": [
      "artifacts/_project/paper/references.bib",
      "docs/paper/references.bib",
      "paper/references.bib"
    ],
    "durationMs": 29,
    "numFiles": 3,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 8_

<details open><summary>🔧 Tool call — Glob · `toolu_01DcWp6P745AYefPfYN6WhvZ`</summary>

```json
{
  "pattern": "**/*.bib",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "a9c39466-a2b1-4e9b-9a5e-21d76c35c7a1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MU3CwpvoAWce86B8SEhMhA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12964,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12964
      },
      "output_tokens": 44,
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

_source line 9 · 2026-05-15T06:01:59.982Z_

<details><summary>↩ Tool result · `toolu_01DcWp6P745AYefPfYN6WhvZ`</summary>

```text
artifacts/_project/paper/references.bib
docs/paper/references.bib
paper/references.bib
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "59f30fb8-c84a-4449-8170-b9b262ced788",
  "tool_use_result": {
    "filenames": [
      "artifacts/_project/paper/references.bib",
      "docs/paper/references.bib",
      "paper/references.bib"
    ],
    "durationMs": 26,
    "numFiles": 3,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 10_

<details open><summary>🔧 Tool call — Glob · `toolu_01F4nEbmhY4TMFhBrA9yQoo8`</summary>

```json
{
  "pattern": "**/related*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "929f67e8-4c7e-4c79-97fd-ed66a6f579aa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MU3CwpvoAWce86B8SEhMhA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12964,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12964
      },
      "output_tokens": 44,
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

_source line 11 · 2026-05-15T06:02:00.588Z_

<details><summary>↩ Tool result · `toolu_01F4nEbmhY4TMFhBrA9yQoo8`</summary>

```text
docs/paper/related_work.tex
artifacts/_project/paper/related_work_b05493.tex
artifacts/_project/paper/related_work.tex
paper/related_work.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "c4b29df2-a85c-4af1-a601-6e09457d3a66",
  "tool_use_result": {
    "filenames": [
      "docs/paper/related_work.tex",
      "artifacts/_project/paper/related_work_b05493.tex",
      "artifacts/_project/paper/related_work.tex",
      "paper/related_work.tex"
    ],
    "durationMs": 24,
    "numFiles": 4,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 12_

<details open><summary>🔧 Tool call — Grep · `toolu_01QGKoXSCYRaEB1sAaPFm1E2`</summary>

```json
{
  "pattern": "spurious|Shao|metr|METR|reward.hacking",
  "-i": true,
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/references.bib",
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
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "4802fb03-9636-4254-ae28-68fa0cf02c21",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Lg1nzJfFDHuyTE5ygsPk7A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 505,
      "cache_read_input_tokens": 24805,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 505
      },
      "output_tokens": 53,
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

_source line 13 · 2026-05-15T06:02:05.295Z_

<details><summary>↩ Tool result · `toolu_01QGKoXSCYRaEB1sAaPFm1E2`</summary>

```text
6:  author       = {Zhihong Shao and Peiyi Wang and Qihao Zhu and Runxin Xu and others},
74:@inproceedings{skalse-reward-hacking,
76:  title        = {{Defining and Characterizing Reward Hacking}},
106:@article{spurious-rewards,
107:  author       = {Rulin Shao and Shuyue Stella Li and Rui Xin and Scott Geng and Yiping Wang and Sewoong Oh and Simon Shaolei Du and Nathan Lambert and Sewon Min and Ranjay Krishna and Yulia Tsvetkov and Hannaneh Hajishirzi and Pang Wei Koh and Luke Zettlemoyer},
108:  title        = {{Spurious Rewards: Rethinking Training Signals in RLVR}},
203:  author       = {Peiyi Wang and Lei Li and Zhihong Shao and Runxin Xu and others},
214:@article{reward-hacking-survey,
216:  title        = {{Reward Hacking in the Era of Large Models: Mechanisms, Emergent Misalignment, Challenges}},
249:@misc{metr-reward-hacking,
250:  author       = {{METR}},
251:  title        = {{Recent Frontier Models Are Reward Hacking}},
253:  howpublished = {METR blog post},
254:  note         = {\url{https://metr.org/blog/2025-06-05-recent-reward-hacking/}},
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "a03710e6-c5c8-4533-a2d9-4591097289af",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "6:  author       = {Zhihong Shao and Peiyi Wang and Qihao Zhu and Runxin Xu and others},\n74:@inproceedings{skalse-reward-hacking,\n76:  title        = {{Defining and Characterizing Reward Hacking}},\n106:@article{spurious-rewards,\n107:  author       = {Rulin Shao and Shuyue Stella Li and Rui Xin and Scott Geng and Yiping Wang and Sewoong Oh and Simon Shaolei Du and Nathan Lambert and Sewon Min and Ranjay Krishna and Yulia Tsvetkov and Hannaneh Hajishirzi and Pang Wei Koh and Luke Zettlemoyer},\n108:  title        = {{Spurious Rewards: Rethinking Training Signals in RLVR}},\n203:  author       = {Peiyi Wang and Lei Li and Zhihong Shao and Runxin Xu and others},\n214:@article{reward-hacking-survey,\n216:  title        = {{Reward Hacking in the Era of Large Models: Mechanisms, Emergent Misalignment, Challenges}},\n249:@misc{metr-reward-hacking,\n250:  author       = {{METR}},\n251:  title        = {{Recent Frontier Models Are Reward Hacking}},\n253:  howpublished = {METR blog post},\n254:  note         = {\\url{https://metr.org/blog/2025-06-05-recent-reward-hacking/}},",
    "numLines": 14
  }
}
```

</details>

---

### Tool call

_source line 14_

<details open><summary>🔧 Tool call — Grep · `toolu_01SBmvPSa3edxm4aiP3PyKq1`</summary>

```json
{
  "pattern": "spurious|metr|reward.hack",
  "-i": true,
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/related_work.tex",
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
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "3fdd2174-a25c-401b-b39d-1850c59eafa1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Lg1nzJfFDHuyTE5ygsPk7A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 505,
      "cache_read_input_tokens": 24805,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 505
      },
      "output_tokens": 53,
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

_source line 15 · 2026-05-15T06:02:06.099Z_

<details><summary>↩ Tool result · `toolu_01SBmvPSa3edxm4aiP3PyKq1`</summary>

```text
9:\paragraph{Reward hacking and Goodhart's Law.}
10:Goodhart's Law is established theoretically~\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "9c66cb55-e085-4c1c-a494-8ce13df7e457",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "9:\\paragraph{Reward hacking and Goodhart's Law.}\n10:Goodhart's Law is established theoretically~\\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.",
    "numLines": 2
  }
}
```

</details>

---

### Assistant

_source line 16_

bib 文件中两个 entry 都已存在（`spurious-rewards` 在第106行，`metr-reward-hacking` 在第249行），但 Related Work 中尚未引用它们。让我看一下 reward hacking 段落的完整内容，找到合适的插入位置。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "189a4198-951e-49dc-bfec-b6dc78c40018",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017PArhwc4Dm2s87fYXX1MrH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 850,
      "cache_read_input_tokens": 25310,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 850
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

_source line 17_

<details open><summary>🔧 Tool call — Read · `toolu_01QaQuH7PZ8R752JA2qay7HY`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "a27b57bf-92f6-4fd9-a42e-5a900d9b2c2f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017PArhwc4Dm2s87fYXX1MrH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 850,
      "cache_read_input_tokens": 25310,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 850
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

_source line 18 · 2026-05-15T06:02:10.172Z_

<details><summary>↩ Tool result · `toolu_01QaQuH7PZ8R752JA2qay7HY`</summary>

```text
1	\section{Related Work}
2	\label{sec:related-work}
3	
4	\paragraph{Neurosymbolic reasoning and process rewards.}
5	LLM-solver pipelines~\cite{satlm, logic-lm, linc, fover-pei2025, lorp} and RL methods trained on solver feedback~\cite{mellgren-prolog-grpo, logic-rl} evaluate execution accuracy alone, with no diagnostic for structural quality.
6	Learned PRMs~\cite{lightman-verify-step, math-shepherd} provide step-level feedback but suffer from reward-model noise and distribution shift~\cite{processbench}; ISR is solver-grounded and annotation-free.
7	We use FOLIO~\cite{folio}, the only public NLI benchmark with both FOL and Prolog annotations.
8	
9	\paragraph{Reward hacking and Goodhart's Law.}
10	Goodhart's Law is established theoretically~\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.
11	Our setting differs in three ways: ISR is deterministic and solver-derived rather than learned; gaming \emph{emerges during RL training} rather than at inference time; and the effect operates at a \emph{meta} level---the diagnostic for gaming itself becomes gamed when optimized---a phenomenon, to our knowledge, not previously documented.
12	
13	\paragraph{Mutation testing.}
14	STA adapts the LOO mutation paradigm~\cite{demillo1978, jia-harman-survey} to solver inputs; novelty lies in application and findings, not in the perturbation primitive.
15	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "2235ba5c-ae5d-4c00-8fa6-43c41976f7f3",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related-work}\n\n\\paragraph{Neurosymbolic reasoning and process rewards.}\nLLM-solver pipelines~\\cite{satlm, logic-lm, linc, fover-pei2025, lorp} and RL methods trained on solver feedback~\\cite{mellgren-prolog-grpo, logic-rl} evaluate execution accuracy alone, with no diagnostic for structural quality.\nLearned PRMs~\\cite{lightman-verify-step, math-shepherd} provide step-level feedback but suffer from reward-model noise and distribution shift~\\cite{processbench}; ISR is solver-grounded and annotation-free.\nWe use FOLIO~\\cite{folio}, the only public NLI benchmark with both FOL and Prolog annotations.\n\n\\paragraph{Reward hacking and Goodhart's Law.}\nGoodhart's Law is established theoretically~\\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.\nOur setting differs in three ways: ISR is deterministic and solver-derived rather than learned; gaming \\emph{emerges during RL training} rather than at inference time; and the effect operates at a \\emph{meta} level---the diagnostic for gaming itself becomes gamed when optimized---a phenomenon, to our knowledge, not previously documented.\n\n\\paragraph{Mutation testing.}\nSTA adapts the LOO mutation paradigm~\\cite{demillo1978, jia-harman-survey} to solver inputs; novelty lies in application and findings, not in the perturbation primitive.\n",
      "numLines": 15,
      "startLine": 1,
      "totalLines": 15
    }
  }
}
```

</details>

---

### Assistant

_source line 19_

现在让我在 reward hacking 段落中添加这两篇引用。`spurious-rewards` (Shao et al.) 和 `metr-reward-hacking` (METR) 都与该段落的 empirical evidence 相关。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "8672bc0a-5f38-4a44-b979-08d5d02cb4d5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015cmdvcjzBxCt3bBxaWj8oo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 642,
      "cache_read_input_tokens": 26160,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 642
      },
      "output_tokens": 5,
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

_source line 20_

<details open><summary>🔧 Tool call — Edit · `toolu_017jQP4fSH2Y5n8sHJThQaEW`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/related_work.tex",
  "old_string": "Goodhart's Law is established theoretically~\\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.",
  "new_string": "Goodhart's Law is established theoretically~\\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.\nRecent work further documents spurious reward signals in RLVR~\\cite{spurious-rewards} and reward hacking in frontier models~\\cite{metr-reward-hacking}."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "85a61847-43e6-46c8-a873-867f0f5eaab4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015cmdvcjzBxCt3bBxaWj8oo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 642,
      "cache_read_input_tokens": 26160,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 642
      },
      "output_tokens": 5,
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

_source line 21 · 2026-05-15T06:02:16.025Z_

<details><summary>↩ Tool result · `toolu_017jQP4fSH2Y5n8sHJThQaEW`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/related_work.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "2b752424-6386-4a1b-ae44-78dd07717d82",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/related_work.tex",
    "oldString": "Goodhart's Law is established theoretically~\\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.",
    "newString": "Goodhart's Law is established theoretically~\\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.\nRecent work further documents spurious reward signals in RLVR~\\cite{spurious-rewards} and reward hacking in frontier models~\\cite{metr-reward-hacking}.",
    "originalFile": "\\section{Related Work}\n\\label{sec:related-work}\n\n\\paragraph{Neurosymbolic reasoning and process rewards.}\nLLM-solver pipelines~\\cite{satlm, logic-lm, linc, fover-pei2025, lorp} and RL methods trained on solver feedback~\\cite{mellgren-prolog-grpo, logic-rl} evaluate execution accuracy alone, with no diagnostic for structural quality.\nLearned PRMs~\\cite{lightman-verify-step, math-shepherd} provide step-level feedback but suffer from reward-model noise and distribution shift~\\cite{processbench}; ISR is solver-grounded and annotation-free.\nWe use FOLIO~\\cite{folio}, the only public NLI benchmark with both FOL and Prolog annotations.\n\n\\paragraph{Reward hacking and Goodhart's Law.}\nGoodhart's Law is established theoretically~\\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.\nOur setting differs in three ways: ISR is deterministic and solver-derived rather than learned; gaming \\emph{emerges during RL training} rather than at inference time; and the effect operates at a \\emph{meta} level---the diagnostic for gaming itself becomes gamed when optimized---a phenomenon, to our knowledge, not previously documented.\n\n\\paragraph{Mutation testing.}\nSTA adapts the LOO mutation paradigm~\\cite{demillo1978, jia-harman-survey} to solver inputs; novelty lies in application and findings, not in the perturbation primitive.\n",
    "structuredPatch": [
      {
        "oldStart": 8,
        "oldLines": 6,
        "newStart": 8,
        "newLines": 7,
        "lines": [
          " ",
          " \\paragraph{Reward hacking and Goodhart's Law.}",
          " Goodhart's Law is established theoretically~\\cite{manheim-goodhart-taxonomy, skalse-reward-hacking, karwowski-goodhart-rl} and empirically in RLHF and frontier models~\\cite{gao-reward-overoptimization, bondarenko-spec-gaming, kim-game-formalization}.",
          "+Recent work further documents spurious reward signals in RLVR~\\cite{spurious-rewards} and reward hacking in frontier models~\\cite{metr-reward-hacking}.",
          " Our setting differs in three ways: ISR is deterministic and solver-derived rather than learned; gaming \\emph{emerges during RL training} rather than at inference time; and the effect operates at a \\emph{meta} level---the diagnostic for gaming itself becomes gamed when optimized---a phenomenon, to our knowledge, not previously documented.",
          " ",
          " \\paragraph{Mutation testing.}"
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

_source line 22_

同步到 docs/paper/ 副本。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "faa9e3f5-bd35-45b4-8483-5bae69362b3b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015wRhcYqQgNzaDnauaVvrNu",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 574,
      "cache_read_input_tokens": 26802,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 574
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

_source line 23_

<details open><summary>🔧 Tool call — Read · `toolu_01KCy1GMW1DEL85EDy6BbvTu`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "e02d0b50-0a21-4921-9b56-966b0b168f47",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015wRhcYqQgNzaDnauaVvrNu",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 574,
      "cache_read_input_tokens": 26802,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 574
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

_source line 24 · 2026-05-15T06:02:19.295Z_

<details><summary>↩ Tool result · `toolu_01KCy1GMW1DEL85EDy6BbvTu`</summary>

```text
1	\section{Related Work}
2	\label{sec:related-work}
3	
4	\paragraph{Neurosymbolic Reasoning with LLMs.}
5	Prompting-based pipelines couple LLMs with external solvers to offload logical inference.
6	Logic-LM~\cite{logic-lm} generates FOL formalizations verified by an external prover, with a self-refinement loop on solver errors; LINC~\cite{linc} similarly translates natural language to first-order logic for Prover9, demonstrating gains over chain-of-thought on syllogistic and multi-hop tasks.
7	SatLM~\cite{satlm} extends the paradigm to satisfiability solvers via declarative prompting, while LoRP~\cite{lorp} and FoVer~\cite{fover-pei2025} route through Prolog execution traces and FOL verification, respectively, to validate or filter LLM-generated reasoning.
8	All of these systems evaluate on execution accuracy---whether the solver returns the correct answer---without diagnosing the structural quality of the generated formalizations.
9	RL-based training represents a more recent direction.
10	Mellgren~\cite{mellgren-prolog-grpo} applies GRPO to train Prolog formalizers with binary solver reward, reporting substantial prove-rate gains; Logic-RL~\cite{logic-rl} demonstrates that rule-based RL with solver feedback elicits emergent reasoning in LLMs; and Thought-Like-Pro~\cite{thought-like-pro} uses self-driven Prolog chain-of-thought to enhance multi-step reasoning.
11	These RL systems optimize execution reward exclusively, reporting prove rate as the primary success metric.
12	Our work differs in diagnostic focus: STA reveals that execution accuracy conflates faithful derivation with degenerate shortcuts, and ISR quantifies this conflation.
13	The finding that 87\% of proved outputs under exec-only GRPO embed the conclusion among the premises (\S\ref{sec:diagnostic}) applies directly to these systems, suggesting that reported prove-rate gains may overstate genuine reasoning improvement.
14	
15	\paragraph{Reward Shaping and Process Supervision.}
16	Binary outcome rewards provide no gradient on intermediate reasoning quality, motivating process-level supervision.
17	Lightman et al.~\cite{lightman-verify-step} train process reward models (PRMs) that score individual reasoning steps, improving mathematical problem-solving over outcome-only rewards.
18	Math-Shepherd~\cite{math-shepherd} automates step-level annotation by validating intermediate states against reference solutions.
19	Beyond learned PRMs, symbolic feedback offers an alternative grounding: RLSF~\cite{rlsf} uses solver diagnostics as a structured training signal for formal reasoning, and Rubric-GRPO~\cite{rubric-grpo} replaces scalar rewards with multi-dimensional rubric scores evaluated by an LLM judge.
20	However, process rewards introduce their own failure modes.
21	Gao et al.~\cite{gao-effective-rl-reward} show that reward design choices---granularity, normalization, aggregation---can dominate the effect of the underlying signal.
22	PROF~\cite{prof-process-outcome} finds that process and outcome rewards conflict under joint optimization, requiring explicit harmonization.
23	The Qwen PRM study~\cite{qwen-prm-lessons} documents that PRMs degrade unpredictably at distribution shift, and ProGRS~\cite{progrs-outcome-conditioned} introduces outcome-conditioned process rewards to mitigate the gap between step-level correctness and final-answer accuracy.
24	ISR differs from these approaches in that it is solver-grounded rather than learned: it derives directly from deterministic LOO ablation of solver inputs, eliminating reward model noise.
25	Our finding that ISR reliably \emph{diagnoses} structural quality yet becomes the target of gaming when used as a training reward (\S\ref{sec:goodhart}) adds an empirical data point to this literature: even non-learned process signals can Goodhart when optimized.
26	
27	\paragraph{Reward Hacking and Goodhart's Law.}
28	Gao et al.~\cite{gao-reward-overoptimization} establish scaling laws for reward model overoptimization, showing that proxy reward increases monotonically with optimization pressure until true performance collapses.
29	Manheim and Garrabrant~\cite{manheim-goodhart-taxonomy} taxonomize four variants of Goodhart's Law---regressional, extremal, causal, and adversarial---while Skalse et al.~\cite{skalse-reward-hacking} prove that reward hacking is generically unavoidable for imperfect proxies.
30	Karwowski et al.~\cite{karwowski-goodhart-rl} demonstrate Goodhart dynamics geometrically in RL, showing that KL regularization delays but does not prevent overoptimization; Pan et al.~\cite{pan-reward-misspecification} map how misspecified rewards produce qualitatively different failure modes depending on the degree of misalignment; and Kwa et al.~\cite{kwa-catastrophic-goodhart} show that KL divergence regularization fails catastrophically under heavy-tailed reward misspecification.
31	In the LLM setting specifically, Bondarenko et al.~\cite{bondarenko-spec-gaming} demonstrate specification gaming in reasoning models, Kim et al.~\cite{kim-game-formalization} evaluate whether LLMs game logical formalization tasks, and Yang et al.~\cite{spurious-rewards} identify spurious reward signals in RLVR that inflate metrics without genuine capability gains.
32	This literature analyzes Goodhart dynamics either theoretically or within RLHF/text generation, where the proxy is a learned reward model.
33	Our setting differs in two respects: the proxy (ISR) is deterministic and solver-derived, eliminating reward model noise as an explanation; and the Goodhart effect operates at a \emph{meta} level---ISR was designed to \emph{detect} gaming of execution reward, yet itself becomes gamed when optimized.
34	The dose-response pattern we observe ($\beta{=}0.1$: proxy gaming via conclusion duplication; $\beta{=}0.3$: performance collapse) traces the trajectory predicted by Gao et al.~\cite{gao-reward-overoptimization} within a single neurosymbolic RL setup, and the premise-count confound that explains away apparent ISR improvements provides a concrete mechanism for regressional Goodhart in formal reasoning.
35	
36	\paragraph{Mutation Testing and Component Analysis.}
37	Mutation testing originated with DeMillo et al.~\cite{demillo1978}, who proposed injecting systematic faults into programs to assess test suite adequacy; the coupling effect hypothesis~\cite{offutt-coupling} provides the theoretical grounding that simple mutants subsume complex faults.
38	Jia and Harman~\cite{jia-harman-survey} survey three decades of development, establishing leave-one-out and higher-order mutation as the dominant paradigm, while Just et al.~\cite{just-mutants-real-faults} validate that synthetic mutants approximate real faults in detection experiments.
39	Recent work connects mutation testing with LLMs: LLMorpheus~\cite{llmorpheus} uses language models to generate semantically rich mutants that go beyond syntactic operators.
40	STA adapts the core LOO intuition to a different domain---formal logic formalizations---where the ``program under test'' is the solver input and the ``test'' is proof success.
41	The unit of mutation shifts from code statements to logical components (premises in FOL, clauses in Prolog), and the diagnostic target shifts from test adequacy to structural necessity for proof validity.
42	The novelty lies not in the perturbation technique itself but in its application to neurosymbolic RL and the empirical findings it enables: the ISR collapse trajectory, the Goodhart phenomenon, and the taxonomy of hacking modes.
43	
44	\paragraph{Positioning.}
45	This work sits at the intersection of neurosymbolic reasoning, reward design, and Goodhart dynamics.
46	Where prior neurosymbolic systems evaluate on execution accuracy alone, STA provides a structural diagnostic; where prior reward-shaping work assumes that finer-grained signals safely improve training, our ISR-as-reward experiments demonstrate meta-level Goodhart failure; and where prior Goodhart analyses study learned reward models, we show the same dynamics arise from a deterministic, solver-grounded metric.
47	The mutation-testing connection provides the methodological foundation, but the contributions are empirical: structural collapse under RL, meta-level gaming of the diagnostic itself, and a taxonomy of exploitation strategies across formal languages.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "72a74411-a7b9-4e62-8027-715338c5a793",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related-work}\n\n\\paragraph{Neurosymbolic Reasoning with LLMs.}\nPrompting-based pipelines couple LLMs with external solvers to offload logical inference.\nLogic-LM~\\cite{logic-lm} generates FOL formalizations verified by an external prover, with a self-refinement loop on solver errors; LINC~\\cite{linc} similarly translates natural language to first-order logic for Prover9, demonstrating gains over chain-of-thought on syllogistic and multi-hop tasks.\nSatLM~\\cite{satlm} extends the paradigm to satisfiability solvers via declarative prompting, while LoRP~\\cite{lorp} and FoVer~\\cite{fover-pei2025} route through Prolog execution traces and FOL verification, respectively, to validate or filter LLM-generated reasoning.\nAll of these systems evaluate on execution accuracy---whether the solver returns the correct answer---without diagnosing the structural quality of the generated formalizations.\nRL-based training represents a more recent direction.\nMellgren~\\cite{mellgren-prolog-grpo} applies GRPO to train Prolog formalizers with binary solver reward, reporting substantial prove-rate gains; Logic-RL~\\cite{logic-rl} demonstrates that rule-based RL with solver feedback elicits emergent reasoning in LLMs; and Thought-Like-Pro~\\cite{thought-like-pro} uses self-driven Prolog chain-of-thought to enhance multi-step reasoning.\nThese RL systems optimize execution reward exclusively, reporting prove rate as the primary success metric.\nOur work differs in diagnostic focus: STA reveals that execution accuracy conflates faithful derivation with degenerate shortcuts, and ISR quantifies this conflation.\nThe finding that 87\\% of proved outputs under exec-only GRPO embed the conclusion among the premises (\\S\\ref{sec:diagnostic}) applies directly to these systems, suggesting that reported prove-rate gains may overstate genuine reasoning improvement.\n\n\\paragraph{Reward Shaping and Process Supervision.}\nBinary outcome rewards provide no gradient on intermediate reasoning quality, motivating process-level supervision.\nLightman et al.~\\cite{lightman-verify-step} train process reward models (PRMs) that score individual reasoning steps, improving mathematical problem-solving over outcome-only rewards.\nMath-Shepherd~\\cite{math-shepherd} automates step-level annotation by validating intermediate states against reference solutions.\nBeyond learned PRMs, symbolic feedback offers an alternative grounding: RLSF~\\cite{rlsf} uses solver diagnostics as a structured training signal for formal reasoning, and Rubric-GRPO~\\cite{rubric-grpo} replaces scalar rewards with multi-dimensional rubric scores evaluated by an LLM judge.\nHowever, process rewards introduce their own failure modes.\nGao et al.~\\cite{gao-effective-rl-reward} show that reward design choices---granularity, normalization, aggregation---can dominate the effect of the underlying signal.\nPROF~\\cite{prof-process-outcome} finds that process and outcome rewards conflict under joint optimization, requiring explicit harmonization.\nThe Qwen PRM study~\\cite{qwen-prm-lessons} documents that PRMs degrade unpredictably at distribution shift, and ProGRS~\\cite{progrs-outcome-conditioned} introduces outcome-conditioned process rewards to mitigate the gap between step-level correctness and final-answer accuracy.\nISR differs from these approaches in that it is solver-grounded rather than learned: it derives directly from deterministic LOO ablation of solver inputs, eliminating reward model noise.\nOur finding that ISR reliably \\emph{diagnoses} structural quality yet becomes the target of gaming when used as a training reward (\\S\\ref{sec:goodhart}) adds an empirical data point to this literature: even non-learned process signals can Goodhart when optimized.\n\n\\paragraph{Reward Hacking and Goodhart's Law.}\nGao et al.~\\cite{gao-reward-overoptimization} establish scaling laws for reward model overoptimization, showing that proxy reward increases monotonically with optimization pressure until true performance collapses.\nManheim and Garrabrant~\\cite{manheim-goodhart-taxonomy} taxonomize four variants of Goodhart's Law---regressional, extremal, causal, and adversarial---while Skalse et al.~\\cite{skalse-reward-hacking} prove that reward hacking is generically unavoidable for imperfect proxies.\nKarwowski et al.~\\cite{karwowski-goodhart-rl} demonstrate Goodhart dynamics geometrically in RL, showing that KL regularization delays but does not prevent overoptimization; Pan et al.~\\cite{pan-reward-misspecification} map how misspecified rewards produce qualitatively different failure modes depending on the degree of misalignment; and Kwa et al.~\\cite{kwa-catastrophic-goodhart} show that KL divergence regularization fails catastrophically under heavy-tailed reward misspecification.\nIn the LLM setting specifically, Bondarenko et al.~\\cite{bondarenko-spec-gaming} demonstrate specification gaming in reasoning models, Kim et al.~\\cite{kim-game-formalization} evaluate whether LLMs game logical formalization tasks, and Yang et al.~\\cite{spurious-rewards} identify spurious reward signals in RLVR that inflate metrics without genuine capability gains.\nThis literature analyzes Goodhart dynamics either theoretically or within RLHF/text generation, where the proxy is a learned reward model.\nOur setting differs in two respects: the proxy (ISR) is deterministic and solver-derived, eliminating reward model noise as an explanation; and the Goodhart effect operates at a \\emph{meta} level---ISR was designed to \\emph{detect} gaming of execution reward, yet itself becomes gamed when optimized.\nThe dose-response pattern we observe ($\\beta{=}0.1$: proxy gaming via conclusion duplication; $\\beta{=}0.3$: performance collapse) traces the trajectory predicted by Gao et al.~\\cite{gao-reward-overoptimization} within a single neurosymbolic RL setup, and the premise-count confound that explains away apparent ISR improvements provides a concrete mechanism for regressional Goodhart in formal reasoning.\n\n\\paragraph{Mutation Testing and Component Analysis.}\nMutation testing originated with DeMillo et al.~\\cite{demillo1978}, who proposed injecting systematic faults into programs to assess test suite adequacy; the coupling effect hypothesis~\\cite{offutt-coupling} provides the theoretical grounding that simple mutants subsume complex faults.\nJia and Harman~\\cite{jia-harman-survey} survey three decades of development, establishing leave-one-out and higher-order mutation as the dominant paradigm, while Just et al.~\\cite{just-mutants-real-faults} validate that synthetic mutants approximate real faults in detection experiments.\nRecent work connects mutation testing with LLMs: LLMorpheus~\\cite{llmorpheus} uses language models to generate semantically rich mutants that go beyond syntactic operators.\nSTA adapts the core LOO intuition to a different domain---formal logic formalizations---where the ``program under test'' is the solver input and the ``test'' is proof success.\nThe unit of mutation shifts from code statements to logical components (premises in FOL, clauses in Prolog), and the diagnostic target shifts from test adequacy to structural necessity for proof validity.\nThe novelty lies not in the perturbation technique itself but in its application to neurosymbolic RL and the empirical findings it enables: the ISR collapse trajectory, the Goodhart phenomenon, and the taxonomy of hacking modes.\n\n\\paragraph{Positioning.}\nThis work sits at the intersection of neurosymbolic reasoning, reward design, and Goodhart dynamics.\nWhere prior neurosymbolic systems evaluate on execution accuracy alone, STA provides a structural diagnostic; where prior reward-shaping work assumes that finer-grained signals safely improve training, our ISR-as-reward experiments demonstrate meta-level Goodhart failure; and where prior Goodhart analyses study learned reward models, we show the same dynamics arise from a deterministic, solver-grounded metric.\nThe mutation-testing connection provides the methodological foundation, but the contributions are empirical: structural collapse under RL, meta-level gaming of the diagnostic itself, and a taxonomy of exploitation strategies across formal languages.",
      "numLines": 47,
      "startLine": 1,
      "totalLines": 47
    }
  }
}
```

</details>

---

### Assistant

_source line 25_

<details><summary>Logged reasoning block</summary>

```text
The docs/paper/ version is more detailed and already has `spurious-rewards` cited (line 31 mentions Yang et al.~\cite{spurious-rewards}). Let me check if `metr-reward-hacking` is also cited there.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "7361919c-1595-4b8e-8dfb-0c9aaa386a1d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JGKiYF5eDMTEZpPWziExEK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2226,
      "cache_read_input_tokens": 27376,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2226
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

_source line 26_

docs/paper/ 版本已经引用了 `spurious-rewards`（第31行），但没有 `metr-reward-hacking`。让我在该文件中添加 METR 引用。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "5a4f1c97-aeb5-4cff-9246-5c167e7d3fe7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JGKiYF5eDMTEZpPWziExEK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2226,
      "cache_read_input_tokens": 27376,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2226
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

_source line 27_

<details open><summary>🔧 Tool call — Edit · `toolu_016Scff8aDw5mXBJqd5tjUc5`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/docs/paper/related_work.tex",
  "old_string": "This literature analyzes Goodhart dynamics either theoretically or within RLHF/text generation, where the proxy is a learned reward model.",
  "new_string": "Concurrently, METR~\\cite{metr-reward-hacking} documents reward hacking behaviors emerging in frontier models across diverse evaluation settings.\nThis literature analyzes Goodhart dynamics either theoretically or within RLHF/text generation, where the proxy is a learned reward model."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "b35bc35a-ae71-4d0d-8e34-9b92ab5464c0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JGKiYF5eDMTEZpPWziExEK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2226,
      "cache_read_input_tokens": 27376,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2226
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

_source line 28 · 2026-05-15T06:02:26.288Z_

<details><summary>↩ Tool result · `toolu_016Scff8aDw5mXBJqd5tjUc5`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/docs/paper/related_work.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "cdba75d2-a4bc-4392-be8d-258e816a6a08",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/docs/paper/related_work.tex",
    "oldString": "This literature analyzes Goodhart dynamics either theoretically or within RLHF/text generation, where the proxy is a learned reward model.",
    "newString": "Concurrently, METR~\\cite{metr-reward-hacking} documents reward hacking behaviors emerging in frontier models across diverse evaluation settings.\nThis literature analyzes Goodhart dynamics either theoretically or within RLHF/text generation, where the proxy is a learned reward model.",
    "originalFile": "\\section{Related Work}\n\\label{sec:related-work}\n\n\\paragraph{Neurosymbolic Reasoning with LLMs.}\nPrompting-based pipelines couple LLMs with external solvers to offload logical inference.\nLogic-LM~\\cite{logic-lm} generates FOL formalizations verified by an external prover, with a self-refinement loop on solver errors; LINC~\\cite{linc} similarly translates natural language to first-order logic for Prover9, demonstrating gains over chain-of-thought on syllogistic and multi-hop tasks.\nSatLM~\\cite{satlm} extends the paradigm to satisfiability solvers via declarative prompting, while LoRP~\\cite{lorp} and FoVer~\\cite{fover-pei2025} route through Prolog execution traces and FOL verification, respectively, to validate or filter LLM-generated reasoning.\nAll of these systems evaluate on execution accuracy---whether the solver returns the correct answer---without diagnosing the structural quality of the generated formalizations.\nRL-based training represents a more recent direction.\nMellgren~\\cite{mellgren-prolog-grpo} applies GRPO to train Prolog formalizers with binary solver reward, reporting substantial prove-rate gains; Logic-RL~\\cite{logic-rl} demonstrates that rule-based RL with solver feedback elicits emergent reasoning in LLMs; and Thought-Like-Pro~\\cite{thought-like-pro} uses self-driven Prolog chain-of-thought to enhance multi-step reasoning.\nThese RL systems optimize execution reward exclusively, reporting prove rate as the primary success metric.\nOur work differs in diagnostic focus: STA reveals that execution accuracy conflates faithful derivation with degenerate shortcuts, and ISR quantifies this conflation.\nThe finding that 87\\% of proved outputs under exec-only GRPO embed the conclusion among the premises (\\S\\ref{sec:diagnostic}) applies directly to these systems, suggesting that reported prove-rate gains may overstate genuine reasoning improvement.\n\n\\paragraph{Reward Shaping and Process Supervision.}\nBinary outcome rewards provide no gradient on intermediate reasoning quality, motivating process-level supervision.\nLightman et al.~\\cite{lightman-verify-step} train process reward models (PRMs) that score individual reasoning steps, improving mathematical problem-solving over outcome-only rewards.\nMath-Shepherd~\\cite{math-shepherd} automates step-level annotation by validating intermediate states against reference solutions.\nBeyond learned PRMs, symbolic feedback offers an alternative grounding: RLSF~\\cite{rlsf} uses solver diagnostics as a structured training signal for formal reasoning, and Rubric-GRPO~\\cite{rubric-grpo} replaces scalar rewards with multi-dimensional rubric scores evaluated by an LLM judge.\nHowever, process rewards introduce their own failure modes.\nGao et al.~\\cite{gao-effective-rl-reward} show that reward design choices---granularity, normalization, aggregation---can dominate the effect of the underlying signal.\nPROF~\\cite{prof-process-outcome} finds that process and outcome rewards conflict under joint optimization, requiring explicit harmonization.\nThe Qwen PRM study~\\cite{qwen-prm-lessons} documents that PRMs degrade unpredictably at distribution shift, and ProGRS~\\cite{progrs-outcome-conditioned} introduces outcome-conditioned process rewards to mitigate the gap between step-level correctness and final-answer accuracy.\nISR differs from these approaches in that it is solver-grounded rather than learned: it derives directly from deterministic LOO ablation of solver inputs, eliminating reward model noise.\nOur finding that ISR reliably \\emph{diagnoses} structural quality yet becomes the target of gaming when used as a training reward (\\S\\ref{sec:goodhart}) adds an empirical data point to this literature: even non-learned process signals can Goodhart when optimized.\n\n\\paragraph{Reward Hacking and Goodhart's Law.}\nGao et al.~\\cite{gao-reward-overoptimization} establish scaling laws for reward model overoptimization, showing that proxy reward increases monotonically with optimization pressure until true performance collapses.\nManheim and Garrabrant~\\cite{manheim-goodhart-taxonomy} taxonomize four variants of Goodhart's Law---regressional, extremal, causal, and adversarial---while Skalse et al.~\\cite{skalse-reward-hacking} prove that reward hacking is generically unavoidable for imperfect proxies.\nKarwowski et al.~\\cite{karwowski-goodhart-rl} demonstrate Goodhart dynamics geometrically in RL, showing that KL regularization delays but does not prevent overoptimization; Pan et al.~\\cite{pan-reward-misspecification} map how misspecified rewards produce qualitatively different failure modes depending on the degree of misalignment; and Kwa et al.~\\cite{kwa-catastrophic-goodhart} show that KL divergence regularization fails catastrophically under heavy-tailed reward misspecification.\nIn the LLM setting specifically, Bondarenko et al.~\\cite{bondarenko-spec-gaming} demonstrate specification gaming in reasoning models, Kim et al.~\\cite{kim-game-formalization} evaluate whether LLMs game logical formalization tasks, and Yang et al.~\\cite{spurious-rewards} identify spurious reward signals in RLVR that inflate metrics without genuine capability gains.\nThis literature analyzes Goodhart dynamics either theoretically or within RLHF/text generation, where the proxy is a learned reward model.\nOur setting differs in two respects: the proxy (ISR) is deterministic and solver-derived, eliminating reward model noise as an explanation; and the Goodhart effect operates at a \\emph{meta} level---ISR was designed to \\emph{detect} gaming of execution reward, yet itself becomes gamed when optimized.\nThe dose-response pattern we observe ($\\beta{=}0.1$: proxy gaming via conclusion duplication; $\\beta{=}0.3$: performance collapse) traces the trajectory predicted by Gao et al.~\\cite{gao-reward-overoptimization} within a single neurosymbolic RL setup, and the premise-count confound that explains away apparent ISR improvements provides a concrete mechanism for regressional Goodhart in formal reasoning.\n\n\\paragraph{Mutation Testing and Component Analysis.}\nMutation testing originated with DeMillo et al.~\\cite{demillo1978}, who proposed injecting systematic faults into programs to assess test suite adequacy; the coupling effect hypothesis~\\cite{offutt-coupling} provides the theoretical grounding that simple mutants subsume complex faults.\nJia and Harman~\\cite{jia-harman-survey} survey three decades of development, establishing leave-one-out and higher-order mutation as the dominant paradigm, while Just et al.~\\cite{just-mutants-real-faults} validate that synthetic mutants approximate real faults in detection experiments.\nRecent work connects mutation testing with LLMs: LLMorpheus~\\cite{llmorpheus} uses language models to generate semantically rich mutants that go beyond syntactic operators.\nSTA adapts the core LOO intuition to a different domain---formal logic formalizations---where the ``program under test'' is the solver input and the ``test'' is proof success.\nThe unit of mutation shifts from code statements to logical components (premises in FOL, clauses in Prolog), and the diagnostic target shifts from test adequacy to structural necessity for proof validity.\nThe novelty lies not in the perturbation technique itself but in its application to neurosymbolic RL and the empirical findings it enables: the ISR collapse trajectory, the Goodhart phenomenon, and the taxonomy of hacking modes.\n\n\\paragraph{Positioning.}\nThis work sits at the intersection of neurosymbolic reasoning, reward design, and Goodhart dynamics.\nWhere prior neurosymbolic systems evaluate on execution accuracy alone, STA provides a structural diagnostic; where prior reward-shaping work assumes that finer-grained signals safely improve training, our ISR-as-reward experiments demonstrate meta-level Goodhart failure; and where prior Goodhart analyses study learned reward models, we show the same dynamics arise from a deterministic, solver-grounded metric.\nThe mutation-testing connection provides the methodological foundation, but the contributions are empirical: structural collapse under RL, meta-level gaming of the diagnostic itself, and a taxonomy of exploitation strategies across formal languages.",
    "structuredPatch": [
      {
        "oldStart": 29,
        "oldLines": 6,
        "newStart": 29,
        "newLines": 7,
        "lines": [
          " Manheim and Garrabrant~\\cite{manheim-goodhart-taxonomy} taxonomize four variants of Goodhart's Law---regressional, extremal, causal, and adversarial---while Skalse et al.~\\cite{skalse-reward-hacking} prove that reward hacking is generically unavoidable for imperfect proxies.",
          " Karwowski et al.~\\cite{karwowski-goodhart-rl} demonstrate Goodhart dynamics geometrically in RL, showing that KL regularization delays but does not prevent overoptimization; Pan et al.~\\cite{pan-reward-misspecification} map how misspecified rewards produce qualitatively different failure modes depending on the degree of misalignment; and Kwa et al.~\\cite{kwa-catastrophic-goodhart} show that KL divergence regularization fails catastrophically under heavy-tailed reward misspecification.",
          " In the LLM setting specifically, Bondarenko et al.~\\cite{bondarenko-spec-gaming} demonstrate specification gaming in reasoning models, Kim et al.~\\cite{kim-game-formalization} evaluate whether LLMs game logical formalization tasks, and Yang et al.~\\cite{spurious-rewards} identify spurious reward signals in RLVR that inflate metrics without genuine capability gains.",
          "+Concurrently, METR~\\cite{metr-reward-hacking} documents reward hacking behaviors emerging in frontier models across diverse evaluation settings.",
          " This literature analyzes Goodhart dynamics either theoretically or within RLHF/text generation, where the proxy is a learned reward model.",
          " Our setting differs in two respects: the proxy (ISR) is deterministic and solver-derived, eliminating reward model noise as an explanation; and the Goodhart effect operates at a \\emph{meta} level---ISR was designed to \\emph{detect} gaming of execution reward, yet itself becomes gamed when optimized.",
          " The dose-response pattern we observe ($\\beta{=}0.1$: proxy gaming via conclusion duplication; $\\beta{=}0.3$: performance collapse) traces the trajectory predicted by Gao et al.~\\cite{gao-reward-overoptimization} within a single neurosymbolic RL setup, and the premise-count confound that explains away apparent ISR improvements provides a concrete mechanism for regressional Goodhart in formal reasoning."
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

_source line 29_

结果汇总：

**bib 文件** — 两个 entry 均已存在：
- `spurious-rewards`（Rulin Shao et al.）— `references.bib:106`
- `metr-reward-hacking`（METR）— `references.bib:249`

**paper/related_work.tex**（简版）— 两者均缺失，已在第10行 reward hacking 段落末尾新增一句引用两篇。

**docs/paper/related_work.tex**（详版）— `spurious-rewards` 已在第31行被引用；`metr-reward-hacking` 缺失，已在第32行前新增一句引用。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "uuid": "c1707555-dac2-4bc9-8031-a019acb701e3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0188jSWbutumPbMQPnD3Hx9e",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 424,
      "cache_read_input_tokens": 29602,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 424
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

_source line 30_

结果汇总：

**bib 文件** — 两个 entry 均已存在：
- `spurious-rewards`（Rulin Shao et al.）— `references.bib:106`
- `metr-reward-hacking`（METR）— `references.bib:249`

**paper/related_work.tex**（简版）— 两者均缺失，已在第10行 reward hacking 段落末尾新增一句引用两篇。

**docs/paper/related_work.tex**（详版）— `spurious-rewards` 已在第31行被引用；`metr-reward-hacking` 缺失，已在第32行前新增一句引用。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 36655,
  "duration_api_ms": 37760,
  "num_turns": 10,
  "stop_reason": "end_turn",
  "session_id": "6d0f7508-1a40-475f-857b-732c2537e751",
  "total_cost_usd": 0.24816725,
  "usage": {
    "input_tokens": 9,
    "cache_creation_input_tokens": 18185,
    "cache_read_input_tokens": 171896,
    "output_tokens": 1824,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 18185,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 190,
        "cache_read_input_tokens": 29602,
        "cache_creation_input_tokens": 424,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 424
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2833,
      "outputTokens": 17,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.002918,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 9,
      "outputTokens": 1824,
      "cacheReadInputTokens": 171896,
      "cacheCreationInputTokens": 18185,
      "webSearchRequests": 0,
      "costUSD": 0.24524924999999997,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "f5590ba9-f0c2-40fa-9518-ed94af166275"
}
```

</details>

---
