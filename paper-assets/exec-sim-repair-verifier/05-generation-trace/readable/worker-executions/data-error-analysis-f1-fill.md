# data error analysis f1 fill

**A Systematic Comparison of Execution-Free Verification Formulations for Code Repair** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 26
- **Recorded user turns:** 0
- **Tool calls:** 7
- **Original source:** `logs/workers/worker_data_error-analysis-f1-fill_20260515T081953.log`
- **Structured JSON:** [`d3b034c28529d7f72b84.json`](../../sessions/d3/d3b034c28529d7f72b84.json)

## Before a recorded user message

26 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
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
  "uuid": "4df0cd54-53d9-4670-b1e0-f40f7a38c183",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-16-projects-exec-sim-repair-verifier/memory/"
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
    "resetsAt": 1778836800,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "855bf90e-0e08-495e-92dd-3c0f2da1a298",
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d"
}
```

---

### Assistant

_source line 4_

Let me read the file first.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "b98fadcd-789a-4a61-a71c-ee25e49b24ca",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01K7LkfPNUG845gUPvhDJzhD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11453,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11453
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_016YpeE9aNJcNMQrot3Sy6CA`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file",
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
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "cc06b145-5274-47c9-bd42-c107921b0e02",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01K7LkfPNUG845gUPvhDJzhD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11453,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11453
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

_source line 6 · 2026-05-15T08:20:06.918Z_

<details><summary>↩ Tool result · `toolu_016YpeE9aNJcNMQrot3Sy6CA`</summary>

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
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "38922dbd-fb4f-4c01-90d6-bc64be86e820",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__save_project_file"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file",
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
Let me read the error_analysis_data.md file first.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "abb2b69a-634c-45b3-a942-d576032d2ba8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016r3CjymKLG13JvR41tSWaY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 707,
      "cache_read_input_tokens": 22900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 707
      },
      "output_tokens": 61,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01PH1fNpAEShf2ubNL2rKXm3`</summary>

```json
{
  "project": "exec-sim-repair-verifier",
  "file": "error_analysis_data.md",
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
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "99674566-22d4-403b-ab12-cbd9d01b2cf4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016r3CjymKLG13JvR41tSWaY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 707,
      "cache_read_input_tokens": 22900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 707
      },
      "output_tokens": 61,
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

_source line 9 · 2026-05-15T08:20:10.107Z_

<details><summary>↩ Tool result · `toolu_01PH1fNpAEShf2ubNL2rKXm3`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'error_analysis_data.md'\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "e5e85d44-12e8-47a3-a288-6c81d672f54a",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'error_analysis_data.md'\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'error_analysis_data.md'\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 10_

<details><summary>Logged reasoning block</summary>

```text
The file isn't in the whitelist for the MCP tool. Let me check if it exists in the project artifacts directory or somewhere else.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "55d02ef3-94ce-41fa-a96a-8df1403aa599",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PnxNH7m8PkFFjiS9XLbS6r",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 307,
      "cache_read_input_tokens": 23607,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 307
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

_source line 11_

File not in the MCP whitelist. Let me find it on disk.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "f562f35c-11f2-412d-97ff-dc5f267f21a6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PnxNH7m8PkFFjiS9XLbS6r",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 307,
      "cache_read_input_tokens": 23607,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 307
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

_source line 12_

<details open><summary>🔧 Tool call — Glob · `toolu_01Hod6GGBnKytmew2D9XLZ7Y`</summary>

```json
{
  "pattern": "**/error_analysis_data.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "0d1a7724-2a52-4c41-a961-c5cf5d5dc7ca",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PnxNH7m8PkFFjiS9XLbS6r",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 307,
      "cache_read_input_tokens": 23607,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 307
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

_source line 13 · 2026-05-15T08:20:13.494Z_

<details><summary>↩ Tool result · `toolu_01Hod6GGBnKytmew2D9XLZ7Y`</summary>

```text
artifacts/error_analysis_data.md
artifacts/_project/data/error_analysis_data.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "e2a22c91-b258-4805-8835-d594319b9bad",
  "tool_use_result": {
    "filenames": [
      "artifacts/error_analysis_data.md",
      "artifacts/_project/data/error_analysis_data.md"
    ],
    "durationMs": 33,
    "numFiles": 2,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 14_

<details open><summary>🔧 Tool call — Read · `toolu_01Jf8HJDh1FCRXQS9tezLW9H`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/error_analysis_data.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "88df2c24-e6fa-43ef-ae92-7535deff52c5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FcNxptR2YCRC6mqHnjDahL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 156,
      "cache_read_input_tokens": 23914,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 156
      },
      "output_tokens": 41,
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

_source line 15 · 2026-05-15T08:20:16.844Z_

<details><summary>↩ Tool result · `toolu_01Jf8HJDh1FCRXQS9tezLW9H`</summary>

```text
1	# CWM Error Analysis — Paper-Ready Data
2	
3	> Compiled: 2026-05-15. All numbers from registry experiments with matched environments (conda, transformers 4.57.6).
4	
5	---
6	
7	## 1. Headline Numbers: Repo-level CWM vs CLS
8	
9	| Metric | CWM v12 (s42) | CWM seed123 | CLS 4B best | CLS 8B (val-sel) | Majority BL |
10	|--------|---------------|-------------|-------------|------------------|-------------|
11	| **Accuracy** | 58.04% | 59.09% | 82.35% | **83.52%** | 72.96% |
12	| **F1 macro** | 51.67% | 43.43% | 74.74% | ⚠️ TBD | — |
13	| **F1 fail** | 34.12% | 13.67% | 60.87% | ⚠️ TBD | — |
14	| **F1 pass** | 69.22% | 73.19% | 88.60% | ⚠️ TBD | — |
15	| **Unparseable rate** | 53.7% | 67.2% | 1.3% | 0% | — |
16	| **Parseable-only acc** | 42.88% | 42.68% | — | — | — |
17	| **vs Majority (pp)** | −14.92 | −13.87 | +9.39 | +10.56 | 0 |
18	
19	> ⚠️ **D088 修正**: CLS 8B 改用 val-selected ckpt-1000 (test=83.52%)，不再用 test-best ckpt-400 (84.79%)。F1 macro/fail/pass 需从 ckpt-1000 eval 结果补填。
20	
21	- CLS-CWM gap (4B apple-to-apple): CLS v5-conda 76.37% vs CWM v12 58.04% = **18.33pp**
22	- CLS-CWM gap (best 4B CLS vs best 4B CWM): 82.35% vs 58.04% = **24.31pp**
23	- CLS-CWM gap (8B CLS vs 4B CWM): 83.52% vs 58.04% = **25.48pp**
24	- Both CWM seeds **below majority baseline** (72.96%) by ~14pp
25	
26	### Experiment References
27	
28	| exp_id | Model | Seed | Checkpoint | Eval Set |
29	|--------|-------|------|------------|----------|
30	| `repo-level-cwm-v12` | Qwen3-4B | 42 | ckpt-500 | test (n=9784) |
31	| `repo-level-cwm-seed123-conda` | Qwen3-4B | 123 | ckpt-500 | test (n=9784) |
32	| `repo-level-cls-v5` | Qwen3-4B | 42 | ckpt-4600 | test (n=9784) |
33	| `repo-level-cls-v5-conda` | Qwen3-4B | 42 | ckpt-600 | test (n=9784) |
34	| ~~`cls8b-s42-ckpt400-test8192-eval`~~ | ~~Qwen3-8B~~ | ~~42~~ | ~~ckpt-400~~ | ~~test@8192 (n=9784)~~ | ⚠️ superseded by D088 |
35	| `cls8b-s42-ckpt1000-test8192-eval` | Qwen3-8B | 42 | ckpt-1000 | test@8192 (n=9784) | **primary (val-sel)** |
36	
37	---
38	
39	## 2. Error Mode Breakdown (v11 subset-500, config identical to v12)
40	
41	Source: `cwm_error_mode_analysis.md` (500-sample analysis from v11 ckpt-600, max_new_tokens=1024, max_seq_length=2048)
42	
43	### 2.1 Unparseable Rate: 75.2% (376/500)
44	
45	| Category | Count | % of Unparseable |
46	|----------|-------|------------------|
47	| Neither pass nor fail keywords (no_keywords) | 289 | 76.9% |
48	| Both pass AND fail keywords (ambiguous_both) | 86 | 22.9% |
49	| Only fail keywords | 1 | 0.3% |
50	| Only pass keywords | 0 | 0.0% |
51	
52	"Neither" subcategories (289 samples):
53	- pytest dot-progress bars: 48.1%
54	- Command output / logs: 51.2%
55	- All cut off at token budget before reaching verdict
56	
57	### 2.2 Error Source Attribution (167 total errors in subset-500)
58	
59	| Error Source | Count | % of Errors |
60	|-------------|-------|-------------|
61	| Unparseable → defaulted to PASS, but true=FAIL | 96 | **57.5%** |
62	| Wrong parseable: true=PASS, pred=FAIL | 64 | 38.3% |
63	| Wrong parseable: true=FAIL, pred=PASS | 7 | 4.2% |
64	
65	**57.5% of all errors come from the unparseable-defaults-to-majority mechanism**, not from model predictions.
66	
67	### 2.3 Token Budget Exhaustion
68	
69	| Statistic | All Samples | "Neither" Unparseable |
70	|-----------|------------|----------------------|
71	| Mean gen length (chars) | 3,398 | 3,773 |
72	| Median | 3,308 | 3,933 |
73	| Max | 7,582 | 6,582 |
74	| Min | 722 | 1,002 |
75	
76	47.8% of all outputs exceed 3,500 chars. Typical pattern: model outputs `pytest -rA ...` → `test session starts` → hundreds of `.` dots → warnings → **cut off** (never reaches `passed/failed` summary).
77	
78	### 2.4 Parseable Prediction Quality (124/500 = 24.8%)
79	
80	| True Label | n | Accuracy |
81	|-----------|---|----------|
82	| FAIL | 39 | 82.1% |
83	| PASS | 85 | 24.7% |
84	| Overall | 124 | 42.7% |
85	
86	Model hallucinates failures: 64/71 wrong parseable predictions are PASS→FAIL.
87	
88	### 2.5 Input Truncation
89	
90	- 4.2% (21/500) truncated at max_seq_length=2048
91	- Truncated accuracy: 38.1% vs non-truncated: 67.9%
92	- 15/21 truncated samples also unparseable
93	
94	### 2.6 Confusion Matrix (v11 subset-500)
95	
96	| | Pred PASS | Pred FAIL |
97	|---|----------|-----------|
98	| True PASS | 301 (TP) | 64 (FP) |
99	| True FAIL | 103 (FN) | 32 (TN) |
100	
101	---
102	
103	## 3. Per-repo Variation
104	
105	From `repo-level-cwm-v12` notes:
106	- **Worst**: pytest — 25-42% accuracy
107	- **Best**: requests — 64-84% accuracy
108	
109	Per-repo unparseable rate (from task background):
110	- scikit-learn: ~0% unparseable
111	- sphinx: 100% unparseable
112	
113	The enormous per-repo variance reflects that CWM's ability to parse depends on the repo's test framework output format. Repos with concise pytest output (scikit-learn) are parseable; repos with verbose build/sphinx output are universally unparseable.
114	
115	---
116	
117	## 4. Cross-complexity Comparison (Function-level vs Repo-level)
118	
119	### Function-level CLS vs CWM (per-test, 1890 samples)
120	
121	| Config | CLS Acc | CWM Acc | Gap (pp) | p-value | Cohen's d |
122	|--------|---------|---------|----------|---------|-----------|
123	| 4B (5 seeds) | 88.43 ± 0.78 | 87.19 ± 0.37 | +1.24 | 0.025 | 1.24 |
124	| 8B (3 seeds) | 89.39 ± 1.09 | 86.96 ± 0.72 | +2.43 | 0.007 | 4.97 |
125	
126	### Repo-level CLS vs CWM (9784 samples)
127	
128	| Config | CLS Acc | CWM Acc | Gap (pp) |
129	|--------|---------|---------|----------|
130	| 4B apple-to-apple | 76.37% | 58.04% | **+18.33** |
131	| 4B best CLS vs CWM | 82.35% | 58.04% | **+24.31** |
132	| 8B CLS (val-sel) vs 4B CWM | 83.52% | 58.04% | **+25.48** |
133	
134	### Gap Amplification Summary
135	
136	| Complexity Level | CLS-CWM Gap (pp) | CWM Unparseable |
137	|-----------------|-------------------|-----------------|
138	| Function-level (4B) | 1.24 | 0% |
139	| Function-level (8B) | 2.43 | 0% |
140	| Repo-level (4B) | 18-24 | 54-67% |
141	
142	The gap explodes from ~1-2pp to ~24pp as code complexity increases from function-level to repo-level. This is the central C1 claim evidence.
143	
144	---
145	
146	## 5. "Correct by Accident" Analysis
147	
148	CWM's ~58-59% accuracy partly comes from unparseable outputs defaulting to majority class (PASS).
149	
150	- 38% of CWM "correct" predictions (in v12) are unparseable samples that happened to be PASS class
151	- Parseable-only accuracy: 42.88% (v12 s42) / 42.68% (seed123)
152	- Both parseable-only accuracies are below random (50%) — the model is **anti-informative** when parseable
153	
154	---
155	
156	## 6. Scaling Behavior (Function-level)
157	
158	| Method | 4B Mean | 8B Mean | Scaling Gain (pp) |
159	|--------|---------|---------|-------------------|
160	| CLS | 88.43 | 89.39 | **+0.96** |
161	| CWM | 87.19 | 86.96 | **−0.23** |
162	
163	CLS benefits from scaling; CWM does not. CWM's bottleneck is generation overhead, not model capacity. Gap widens: 1.24pp (4B) → 2.43pp (8B), probability of widening p=0.988.
164	
165	---
166	
167	## 7. Three Inherent CWM Failure Modes
168	
169	### Mode 1: Token Budget Exhaustion (primary, ~77% of unparseable)
170	CWM must generate ~3400 chars of execution trace to reach a verdict vs CLS's 1-2 tokens. The model produces realistic pytest sessions with dots, warnings, and file paths that consume the entire budget before reaching any pass/fail summary.
171	
172	### Mode 2: Keyword Ambiguity (~23% of unparseable)
173	Realistic execution traces contain mixed pass/fail signals: test names with "fail", deprecation warnings, partial error messages. Keyword extraction cannot resolve these.
174	
175	### Mode 3: Hallucinated Failures (38% of parseable errors)
176	When parseable, CWM hallucinates failures for passing patches (PASS→FAIL = 64/71 wrong parseable). The model's attempt to simulate execution makes it prone to generating plausible-looking error messages.
177	
178	---
179	
180	## 8. Suggested Figures
181	
182	### Figure A: Per-repo Unparseable Rate (Bar Chart)
183	- X-axis: repos (scikit-learn, requests, django, ..., sphinx)
184	- Y-axis: unparseable rate (0-100%)
185	- Shows dramatic variation from ~0% to 100%
186	- **Position**: Error Analysis subsection or Appendix
187	
188	### Figure B: Error Mode Breakdown (Stacked Bar or Pie)
189	- Segments: no_keywords (77%), ambiguous_both (23%), other (<1%)
190	- Or: token exhaustion vs keyword ambiguity vs degenerate repetition
191	- **Position**: Error Analysis subsection
192	
193	### Figure C: CLS-CWM Gap Amplification (Grouped Bar)
194	- X-axis: function-level 4B, function-level 8B, repo-level 4B
195	- Y-axis: accuracy gap (pp)
196	- Values: 1.24, 2.43, 24.31
197	- **Position**: Main results section, key visualization for C1 claim
198	
199	### Figure D: Error Source Attribution (Stacked Bar)
200	- Three segments: unparseable-default (57.5%), wrong parseable PASS→FAIL (38.3%), wrong parseable FAIL→PASS (4.2%)
201	- **Position**: Error Analysis subsection
202	
203	### Figure E: CWM Scaling Non-benefit (Line Plot)
204	- Two lines: CLS (88.43 → 89.39) vs CWM (87.19 → 86.96)
205	- X-axis: 4B, 8B
206	- **Position**: Discussion or Results
207	
208	---
209	
210	## 9. Paper Placement Recommendations
211	
212	| Data | Section | Rationale |
213	|------|---------|-----------|
214	| CLS-CWM gap amplification (§4 table) | **Results §5.3** (Repo-level) | Central finding, C1 claim |
215	| Error mode breakdown (§2) | **Analysis §5.4** or **§6** | Explains WHY CWM fails |
216	| Unparseable rate comparison (54-67% vs 0-1.3%) | **Results §5.3** | Headline comparison metric |
217	| Parseable-only accuracy (42.88%) | **Analysis §5.4** | Shows CWM is anti-informative |
218	| Correct-by-accident (38%) | **Analysis §5.4** | Deflates apparent CWM performance |
219	| Scaling non-benefit (§6) | **Discussion §7** | Architectural implication |
220	| Token exhaustion examples | **Appendix** | Qualitative illustration |
221	| Per-repo breakdown | **Appendix** | Supporting detail |
222	| Confusion matrix | **Appendix** | Full transparency |
223	
224	---
225	
226	## 10. Key Sentences for the Paper
227	
228	1. "CWM accuracy drops from 87.19% at function-level to 58.04% at repo-level (−29pp), falling 14.92pp below the majority baseline, while CLS maintains above-baseline performance at both complexity levels."
229	
230	2. "53.7-67.2% of CWM outputs are unparseable, with 77% of unparseable cases caused by token budget exhaustion — the model generates realistic pytest execution traces that consume the entire generation budget before reaching any verdict."
231	
232	3. "Even among parseable CWM outputs, accuracy is only 42.88% — below random chance — indicating the model is anti-informative when it does produce interpretable predictions."
233	
234	4. "57.5% of CWM errors stem from the unparseable-defaults-to-majority mechanism rather than incorrect predictions, suggesting the generative approach fundamentally cannot produce reliable execution simulations at repo scale."
235	
236	5. "The CLS-CWM gap widens from 1.24pp (4B) to 2.43pp (8B) at function-level (p=0.025, d=1.24), and explodes to 24pp at repo-level, supporting the hypothesis that classification approaches scale better than generation for execution simulation."
237	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "4be112b8-4092-4068-a03e-908d3be8e879",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/error_analysis_data.md",
      "content": "# CWM Error Analysis — Paper-Ready Data\n\n> Compiled: 2026-05-15. All numbers from registry experiments with matched environments (conda, transformers 4.57.6).\n\n---\n\n## 1. Headline Numbers: Repo-level CWM vs CLS\n\n| Metric | CWM v12 (s42) | CWM seed123 | CLS 4B best | CLS 8B (val-sel) | Majority BL |\n|--------|---------------|-------------|-------------|------------------|-------------|\n| **Accuracy** | 58.04% | 59.09% | 82.35% | **83.52%** | 72.96% |\n| **F1 macro** | 51.67% | 43.43% | 74.74% | ⚠️ TBD | — |\n| **F1 fail** | 34.12% | 13.67% | 60.87% | ⚠️ TBD | — |\n| **F1 pass** | 69.22% | 73.19% | 88.60% | ⚠️ TBD | — |\n| **Unparseable rate** | 53.7% | 67.2% | 1.3% | 0% | — |\n| **Parseable-only acc** | 42.88% | 42.68% | — | — | — |\n| **vs Majority (pp)** | −14.92 | −13.87 | +9.39 | +10.56 | 0 |\n\n> ⚠️ **D088 修正**: CLS 8B 改用 val-selected ckpt-1000 (test=83.52%)，不再用 test-best ckpt-400 (84.79%)。F1 macro/fail/pass 需从 ckpt-1000 eval 结果补填。\n\n- CLS-CWM gap (4B apple-to-apple): CLS v5-conda 76.37% vs CWM v12 58.04% = **18.33pp**\n- CLS-CWM gap (best 4B CLS vs best 4B CWM): 82.35% vs 58.04% = **24.31pp**\n- CLS-CWM gap (8B CLS vs 4B CWM): 83.52% vs 58.04% = **25.48pp**\n- Both CWM seeds **below majority baseline** (72.96%) by ~14pp\n\n### Experiment References\n\n| exp_id | Model | Seed | Checkpoint | Eval Set |\n|--------|-------|------|------------|----------|\n| `repo-level-cwm-v12` | Qwen3-4B | 42 | ckpt-500 | test (n=9784) |\n| `repo-level-cwm-seed123-conda` | Qwen3-4B | 123 | ckpt-500 | test (n=9784) |\n| `repo-level-cls-v5` | Qwen3-4B | 42 | ckpt-4600 | test (n=9784) |\n| `repo-level-cls-v5-conda` | Qwen3-4B | 42 | ckpt-600 | test (n=9784) |\n| ~~`cls8b-s42-ckpt400-test8192-eval`~~ | ~~Qwen3-8B~~ | ~~42~~ | ~~ckpt-400~~ | ~~test@8192 (n=9784)~~ | ⚠️ superseded by D088 |\n| `cls8b-s42-ckpt1000-test8192-eval` | Qwen3-8B | 42 | ckpt-1000 | test@8192 (n=9784) | **primary (val-sel)** |\n\n---\n\n## 2. Error Mode Breakdown (v11 subset-500, config identical to v12)\n\nSource: `cwm_error_mode_analysis.md` (500-sample analysis from v11 ckpt-600, max_new_tokens=1024, max_seq_length=2048)\n\n### 2.1 Unparseable Rate: 75.2% (376/500)\n\n| Category | Count | % of Unparseable |\n|----------|-------|------------------|\n| Neither pass nor fail keywords (no_keywords) | 289 | 76.9% |\n| Both pass AND fail keywords (ambiguous_both) | 86 | 22.9% |\n| Only fail keywords | 1 | 0.3% |\n| Only pass keywords | 0 | 0.0% |\n\n\"Neither\" subcategories (289 samples):\n- pytest dot-progress bars: 48.1%\n- Command output / logs: 51.2%\n- All cut off at token budget before reaching verdict\n\n### 2.2 Error Source Attribution (167 total errors in subset-500)\n\n| Error Source | Count | % of Errors |\n|-------------|-------|-------------|\n| Unparseable → defaulted to PASS, but true=FAIL | 96 | **57.5%** |\n| Wrong parseable: true=PASS, pred=FAIL | 64 | 38.3% |\n| Wrong parseable: true=FAIL, pred=PASS | 7 | 4.2% |\n\n**57.5% of all errors come from the unparseable-defaults-to-majority mechanism**, not from model predictions.\n\n### 2.3 Token Budget Exhaustion\n\n| Statistic | All Samples | \"Neither\" Unparseable |\n|-----------|------------|----------------------|\n| Mean gen length (chars) | 3,398 | 3,773 |\n| Median | 3,308 | 3,933 |\n| Max | 7,582 | 6,582 |\n| Min | 722 | 1,002 |\n\n47.8% of all outputs exceed 3,500 chars. Typical pattern: model outputs `pytest -rA ...` → `test session starts` → hundreds of `.` dots → warnings → **cut off** (never reaches `passed/failed` summary).\n\n### 2.4 Parseable Prediction Quality (124/500 = 24.8%)\n\n| True Label | n | Accuracy |\n|-----------|---|----------|\n| FAIL | 39 | 82.1% |\n| PASS | 85 | 24.7% |\n| Overall | 124 | 42.7% |\n\nModel hallucinates failures: 64/71 wrong parseable predictions are PASS→FAIL.\n\n### 2.5 Input Truncation\n\n- 4.2% (21/500) truncated at max_seq_length=2048\n- Truncated accuracy: 38.1% vs non-truncated: 67.9%\n- 15/21 truncated samples also unparseable\n\n### 2.6 Confusion Matrix (v11 subset-500)\n\n| | Pred PASS | Pred FAIL |\n|---|----------|-----------|\n| True PASS | 301 (TP) | 64 (FP) |\n| True FAIL | 103 (FN) | 32 (TN) |\n\n---\n\n## 3. Per-repo Variation\n\nFrom `repo-level-cwm-v12` notes:\n- **Worst**: pytest — 25-42% accuracy\n- **Best**: requests — 64-84% accuracy\n\nPer-repo unparseable rate (from task background):\n- scikit-learn: ~0% unparseable\n- sphinx: 100% unparseable\n\nThe enormous per-repo variance reflects that CWM's ability to parse depends on the repo's test framework output format. Repos with concise pytest output (scikit-learn) are parseable; repos with verbose build/sphinx output are universally unparseable.\n\n---\n\n## 4. Cross-complexity Comparison (Function-level vs Repo-level)\n\n### Function-level CLS vs CWM (per-test, 1890 samples)\n\n| Config | CLS Acc | CWM Acc | Gap (pp) | p-value | Cohen's d |\n|--------|---------|---------|----------|---------|-----------|\n| 4B (5 seeds) | 88.43 ± 0.78 | 87.19 ± 0.37 | +1.24 | 0.025 | 1.24 |\n| 8B (3 seeds) | 89.39 ± 1.09 | 86.96 ± 0.72 | +2.43 | 0.007 | 4.97 |\n\n### Repo-level CLS vs CWM (9784 samples)\n\n| Config | CLS Acc | CWM Acc | Gap (pp) |\n|--------|---------|---------|----------|\n| 4B apple-to-apple | 76.37% | 58.04% | **+18.33** |\n| 4B best CLS vs CWM | 82.35% | 58.04% | **+24.31** |\n| 8B CLS (val-sel) vs 4B CWM | 83.52% | 58.04% | **+25.48** |\n\n### Gap Amplification Summary\n\n| Complexity Level | CLS-CWM Gap (pp) | CWM Unparseable |\n|-----------------|-------------------|-----------------|\n| Function-level (4B) | 1.24 | 0% |\n| Function-level (8B) | 2.43 | 0% |\n| Repo-level (4B) | 18-24 | 54-67% |\n\nThe gap explodes from ~1-2pp to ~24pp as code complexity increases from function-level to repo-level. This is the central C1 claim evidence.\n\n---\n\n## 5. \"Correct by Accident\" Analysis\n\nCWM's ~58-59% accuracy partly comes from unparseable outputs defaulting to majority class (PASS).\n\n- 38% of CWM \"correct\" predictions (in v12) are unparseable samples that happened to be PASS class\n- Parseable-only accuracy: 42.88% (v12 s42) / 42.68% (seed123)\n- Both parseable-only accuracies are below random (50%) — the model is **anti-informative** when parseable\n\n---\n\n## 6. Scaling Behavior (Function-level)\n\n| Method | 4B Mean | 8B Mean | Scaling Gain (pp) |\n|--------|---------|---------|-------------------|\n| CLS | 88.43 | 89.39 | **+0.96** |\n| CWM | 87.19 | 86.96 | **−0.23** |\n\nCLS benefits from scaling; CWM does not. CWM's bottleneck is generation overhead, not model capacity. Gap widens: 1.24pp (4B) → 2.43pp (8B), probability of widening p=0.988.\n\n---\n\n## 7. Three Inherent CWM Failure Modes\n\n### Mode 1: Token Budget Exhaustion (primary, ~77% of unparseable)\nCWM must generate ~3400 chars of execution trace to reach a verdict vs CLS's 1-2 tokens. The model produces realistic pytest sessions with dots, warnings, and file paths that consume the entire budget before reaching any pass/fail summary.\n\n### Mode 2: Keyword Ambiguity (~23% of unparseable)\nRealistic execution traces contain mixed pass/fail signals: test names with \"fail\", deprecation warnings, partial error messages. Keyword extraction cannot resolve these.\n\n### Mode 3: Hallucinated Failures (38% of parseable errors)\nWhen parseable, CWM hallucinates failures for passing patches (PASS→FAIL = 64/71 wrong parseable). The model's attempt to simulate execution makes it prone to generating plausible-looking error messages.\n\n---\n\n## 8. Suggested Figures\n\n### Figure A: Per-repo Unparseable Rate (Bar Chart)\n- X-axis: repos (scikit-learn, requests, django, ..., sphinx)\n- Y-axis: unparseable rate (0-100%)\n- Shows dramatic variation from ~0% to 100%\n- **Position**: Error Analysis subsection or Appendix\n\n### Figure B: Error Mode Breakdown (Stacked Bar or Pie)\n- Segments: no_keywords (77%), ambiguous_both (23%), other (<1%)\n- Or: token exhaustion vs keyword ambiguity vs degenerate repetition\n- **Position**: Error Analysis subsection\n\n### Figure C: CLS-CWM Gap Amplification (Grouped Bar)\n- X-axis: function-level 4B, function-level 8B, repo-level 4B\n- Y-axis: accuracy gap (pp)\n- Values: 1.24, 2.43, 24.31\n- **Position**: Main results section, key visualization for C1 claim\n\n### Figure D: Error Source Attribution (Stacked Bar)\n- Three segments: unparseable-default (57.5%), wrong parseable PASS→FAIL (38.3%), wrong parseable FAIL→PASS (4.2%)\n- **Position**: Error Analysis subsection\n\n### Figure E: CWM Scaling Non-benefit (Line Plot)\n- Two lines: CLS (88.43 → 89.39) vs CWM (87.19 → 86.96)\n- X-axis: 4B, 8B\n- **Position**: Discussion or Results\n\n---\n\n## 9. Paper Placement Recommendations\n\n| Data | Section | Rationale |\n|------|---------|-----------|\n| CLS-CWM gap amplification (§4 table) | **Results §5.3** (Repo-level) | Central finding, C1 claim |\n| Error mode breakdown (§2) | **Analysis §5.4** or **§6** | Explains WHY CWM fails |\n| Unparseable rate comparison (54-67% vs 0-1.3%) | **Results §5.3** | Headline comparison metric |\n| Parseable-only accuracy (42.88%) | **Analysis §5.4** | Shows CWM is anti-informative |\n| Correct-by-accident (38%) | **Analysis §5.4** | Deflates apparent CWM performance |\n| Scaling non-benefit (§6) | **Discussion §7** | Architectural implication |\n| Token exhaustion examples | **Appendix** | Qualitative illustration |\n| Per-repo breakdown | **Appendix** | Supporting detail |\n| Confusion matrix | **Appendix** | Full transparency |\n\n---\n\n## 10. Key Sentences for the Paper\n\n1. \"CWM accuracy drops from 87.19% at function-level to 58.04% at repo-level (−29pp), falling 14.92pp below the majority baseline, while CLS maintains above-baseline performance at both complexity levels.\"\n\n2. \"53.7-67.2% of CWM outputs are unparseable, with 77% of unparseable cases caused by token budget exhaustion — the model generates realistic pytest execution traces that consume the entire generation budget before reaching any verdict.\"\n\n3. \"Even among parseable CWM outputs, accuracy is only 42.88% — below random chance — indicating the model is anti-informative when it does produce interpretable predictions.\"\n\n4. \"57.5% of CWM errors stem from the unparseable-defaults-to-majority mechanism rather than incorrect predictions, suggesting the generative approach fundamentally cannot produce reliable execution simulations at repo scale.\"\n\n5. \"The CLS-CWM gap widens from 1.24pp (4B) to 2.43pp (8B) at function-level (p=0.025, d=1.24), and explodes to 24pp at repo-level, supporting the hypothesis that classification approaches scale better than generation for execution simulation.\"\n",
      "numLines": 237,
      "startLine": 1,
      "totalLines": 237
    }
  }
}
```

</details>

---

### Assistant

_source line 16_

<details><summary>Logged reasoning block</summary>

```text
I found the TBD markers in lines 12-14. Let me replace them with the actual values.

Line 12: `| **F1 macro** | 51.67% | 43.43% | 74.74% | ⚠️ TBD | — |` → replace `⚠️ TBD` with `**77.50%**`
Line 13: `| **F1 fail** | 34.12% | 13.67% | 60.87% | ⚠️ TBD | — |` → replace `⚠️ TBD` with `**65.85%**`


Line 14: `| **F1 pass** | 69.22% | 73.19% | 88.60% | ⚠️ TBD | — |` → replace `⚠️ TBD` with `**89.14%**`

I also need to update the TBD note on line 19. Looking at the confusion matrix data provided for CLS 8B (TP=6618, FP=1092, FN=520, TN=1554), I don't see a placeholder for it in the existing tables, so I'll check if the confusion matrix in §2.6 needs updating.

Actually, let me just focus on replacing the TBD markers as requested and make those edits now.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "1ee2cc2e-615a-4356-ad1e-5900b8d714ed",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TJWipxNZU4C9TWhxpqwUBa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4530,
      "cache_read_input_tokens": 24070,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4530
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

_source line 17_

找到 3 处 TBD（行 12-14）和 1 处说明注释（行 19）。开始替换。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "200b4f1c-39a8-441c-9e1b-13af585494b4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TJWipxNZU4C9TWhxpqwUBa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4530,
      "cache_read_input_tokens": 24070,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4530
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

_source line 18_

<details open><summary>🔧 Tool call — Edit · `toolu_01WL4boufqbSTL7E2r8T6r62`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/error_analysis_data.md",
  "old_string": "| **F1 macro** | 51.67% | 43.43% | 74.74% | ⚠️ TBD | — |\n| **F1 fail** | 34.12% | 13.67% | 60.87% | ⚠️ TBD | — |\n| **F1 pass** | 69.22% | 73.19% | 88.60% | ⚠️ TBD | — |",
  "new_string": "| **F1 macro** | 51.67% | 43.43% | 74.74% | **77.50%** | — |\n| **F1 fail** | 34.12% | 13.67% | 60.87% | **65.85%** | — |\n| **F1 pass** | 69.22% | 73.19% | 88.60% | **89.14%** | — |"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "19130a43-b110-44b5-adee-30d2dd13b9b7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TJWipxNZU4C9TWhxpqwUBa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4530,
      "cache_read_input_tokens": 24070,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4530
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

_source line 19 · 2026-05-15T08:20:31.649Z_

<details><summary>↩ Tool result · `toolu_01WL4boufqbSTL7E2r8T6r62`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/error_analysis_data.md has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "d2aba891-6288-4828-91a7-f9738c8126d5",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/error_analysis_data.md",
    "oldString": "| **F1 macro** | 51.67% | 43.43% | 74.74% | ⚠️ TBD | — |\n| **F1 fail** | 34.12% | 13.67% | 60.87% | ⚠️ TBD | — |\n| **F1 pass** | 69.22% | 73.19% | 88.60% | ⚠️ TBD | — |",
    "newString": "| **F1 macro** | 51.67% | 43.43% | 74.74% | **77.50%** | — |\n| **F1 fail** | 34.12% | 13.67% | 60.87% | **65.85%** | — |\n| **F1 pass** | 69.22% | 73.19% | 88.60% | **89.14%** | — |",
    "originalFile": "# CWM Error Analysis — Paper-Ready Data\n\n> Compiled: 2026-05-15. All numbers from registry experiments with matched environments (conda, transformers 4.57.6).\n\n---\n\n## 1. Headline Numbers: Repo-level CWM vs CLS\n\n| Metric | CWM v12 (s42) | CWM seed123 | CLS 4B best | CLS 8B (val-sel) | Majority BL |\n|--------|---------------|-------------|-------------|------------------|-------------|\n| **Accuracy** | 58.04% | 59.09% | 82.35% | **83.52%** | 72.96% |\n| **F1 macro** | 51.67% | 43.43% | 74.74% | ⚠️ TBD | — |\n| **F1 fail** | 34.12% | 13.67% | 60.87% | ⚠️ TBD | — |\n| **F1 pass** | 69.22% | 73.19% | 88.60% | ⚠️ TBD | — |\n| **Unparseable rate** | 53.7% | 67.2% | 1.3% | 0% | — |\n| **Parseable-only acc** | 42.88% | 42.68% | — | — | — |\n| **vs Majority (pp)** | −14.92 | −13.87 | +9.39 | +10.56 | 0 |\n\n> ⚠️ **D088 修正**: CLS 8B 改用 val-selected ckpt-1000 (test=83.52%)，不再用 test-best ckpt-400 (84.79%)。F1 macro/fail/pass 需从 ckpt-1000 eval 结果补填。\n\n- CLS-CWM gap (4B apple-to-apple): CLS v5-conda 76.37% vs CWM v12 58.04% = **18.33pp**\n- CLS-CWM gap (best 4B CLS vs best 4B CWM): 82.35% vs 58.04% = **24.31pp**\n- CLS-CWM gap (8B CLS vs 4B CWM): 83.52% vs 58.04% = **25.48pp**\n- Both CWM seeds **below majority baseline** (72.96%) by ~14pp\n\n### Experiment References\n\n| exp_id | Model | Seed | Checkpoint | Eval Set |\n|--------|-------|------|------------|----------|\n| `repo-level-cwm-v12` | Qwen3-4B | 42 | ckpt-500 | test (n=9784) |\n| `repo-level-cwm-seed123-conda` | Qwen3-4B | 123 | ckpt-500 | test (n=9784) |\n| `repo-level-cls-v5` | Qwen3-4B | 42 | ckpt-4600 | test (n=9784) |\n| `repo-level-cls-v5-conda` | Qwen3-4B | 42 | ckpt-600 | test (n=9784) |\n| ~~`cls8b-s42-ckpt400-test8192-eval`~~ | ~~Qwen3-8B~~ | ~~42~~ | ~~ckpt-400~~ | ~~test@8192 (n=9784)~~ | ⚠️ superseded by D088 |\n| `cls8b-s42-ckpt1000-test8192-eval` | Qwen3-8B | 42 | ckpt-1000 | test@8192 (n=9784) | **primary (val-sel)** |\n\n---\n\n## 2. Error Mode Breakdown (v11 subset-500, config identical to v12)\n\nSource: `cwm_error_mode_analysis.md` (500-sample analysis from v11 ckpt-600, max_new_tokens=1024, max_seq_length=2048)\n\n### 2.1 Unparseable Rate: 75.2% (376/500)\n\n| Category | Count | % of Unparseable |\n|----------|-------|------------------|\n| Neither pass nor fail keywords (no_keywords) | 289 | 76.9% |\n| Both pass AND fail keywords (ambiguous_both) | 86 | 22.9% |\n| Only fail keywords | 1 | 0.3% |\n| Only pass keywords | 0 | 0.0% |\n\n\"Neither\" subcategories (289 samples):\n- pytest dot-progress bars: 48.1%\n- Command output / logs: 51.2%\n- All cut off at token budget before reaching verdict\n\n### 2.2 Error Source Attribution (167 total errors in subset-500)\n\n| Error Source | Count | % of Errors |\n|-------------|-------|-------------|\n| Unparseable → defaulted to PASS, but true=FAIL | 96 | **57.5%** |\n| Wrong parseable: true=PASS, pred=FAIL | 64 | 38.3% |\n| Wrong parseable: true=FAIL, pred=PASS | 7 | 4.2% |\n\n**57.5% of all errors come from the unparseable-defaults-to-majority mechanism**, not from model predictions.\n\n### 2.3 Token Budget Exhaustion\n\n| Statistic | All Samples | \"Neither\" Unparseable |\n|-----------|------------|----------------------|\n| Mean gen length (chars) | 3,398 | 3,773 |\n| Median | 3,308 | 3,933 |\n| Max | 7,582 | 6,582 |\n| Min | 722 | 1,002 |\n\n47.8% of all outputs exceed 3,500 chars. Typical pattern: model outputs `pytest -rA ...` → `test session starts` → hundreds of `.` dots → warnings → **cut off** (never reaches `passed/failed` summary).\n\n### 2.4 Parseable Prediction Quality (124/500 = 24.8%)\n\n| True Label | n | Accuracy |\n|-----------|---|----------|\n| FAIL | 39 | 82.1% |\n| PASS | 85 | 24.7% |\n| Overall | 124 | 42.7% |\n\nModel hallucinates failures: 64/71 wrong parseable predictions are PASS→FAIL.\n\n### 2.5 Input Truncation\n\n- 4.2% (21/500) truncated at max_seq_length=2048\n- Truncated accuracy: 38.1% vs non-truncated: 67.9%\n- 15/21 truncated samples also unparseable\n\n### 2.6 Confusion Matrix (v11 subset-500)\n\n| | Pred PASS | Pred FAIL |\n|---|----------|-----------|\n| True PASS | 301 (TP) | 64 (FP) |\n| True FAIL | 103 (FN) | 32 (TN) |\n\n---\n\n## 3. Per-repo Variation\n\nFrom `repo-level-cwm-v12` notes:\n- **Worst**: pytest — 25-42% accuracy\n- **Best**: requests — 64-84% accuracy\n\nPer-repo unparseable rate (from task background):\n- scikit-learn: ~0% unparseable\n- sphinx: 100% unparseable\n\nThe enormous per-repo variance reflects that CWM's ability to parse depends on the repo's test framework output format. Repos with concise pytest output (scikit-learn) are parseable; repos with verbose build/sphinx output are universally unparseable.\n\n---\n\n## 4. Cross-complexity Comparison (Function-level vs Repo-level)\n\n### Function-level CLS vs CWM (per-test, 1890 samples)\n\n| Config | CLS Acc | CWM Acc | Gap (pp) | p-value | Cohen's d |\n|--------|---------|---------|----------|---------|-----------|\n| 4B (5 seeds) | 88.43 ± 0.78 | 87.19 ± 0.37 | +1.24 | 0.025 | 1.24 |\n| 8B (3 seeds) | 89.39 ± 1.09 | 86.96 ± 0.72 | +2.43 | 0.007 | 4.97 |\n\n### Repo-level CLS vs CWM (9784 samples)\n\n| Config | CLS Acc | CWM Acc | Gap (pp) |\n|--------|---------|---------|----------|\n| 4B apple-to-apple | 76.37% | 58.04% | **+18.33** |\n| 4B best CLS vs CWM | 82.35% | 58.04% | **+24.31** |\n| 8B CLS (val-sel) vs 4B CWM | 83.52% | 58.04% | **+25.48** |\n\n### Gap Amplification Summary\n\n| Complexity Level | CLS-CWM Gap (pp) | CWM Unparseable |\n|-----------------|-------------------|-----------------|\n| Function-level (4B) | 1.24 | 0% |\n| Function-level (8B) | 2.43 | 0% |\n| Repo-level (4B) | 18-24 | 54-67% |\n\nThe gap explodes from ~1-2pp to ~24pp as code complexity increases from function-level to repo-level. This is the central C1 claim evidence.\n\n---\n\n## 5. \"Correct by Accident\" Analysis\n\nCWM's ~58-59% accuracy partly comes from unparseable outputs defaulting to majority class (PASS).\n\n- 38% of CWM \"correct\" predictions (in v12) are unparseable samples that happened to be PASS class\n- Parseable-only accuracy: 42.88% (v12 s42) / 42.68% (seed123)\n- Both parseable-only accuracies are below random (50%) — the model is **anti-informative** when parseable\n\n---\n\n## 6. Scaling Behavior (Function-level)\n\n| Method | 4B Mean | 8B Mean | Scaling Gain (pp) |\n|--------|---------|---------|-------------------|\n| CLS | 88.43 | 89.39 | **+0.96** |\n| CWM | 87.19 | 86.96 | **−0.23** |\n\nCLS benefits from scaling; CWM does not. CWM's bottleneck is generation overhead, not model capacity. Gap widens: 1.24pp (4B) → 2.43pp (8B), probability of widening p=0.988.\n\n---\n\n## 7. Three Inherent CWM Failure Modes\n\n### Mode 1: Token Budget Exhaustion (primary, ~77% of unparseable)\nCWM must generate ~3400 chars of execution trace to reach a verdict vs CLS's 1-2 tokens. The model produces realistic pytest sessions with dots, warnings, and file paths that consume the entire budget before reaching any pass/fail summary.\n\n### Mode 2: Keyword Ambiguity (~23% of unparseable)\nRealistic execution traces contain mixed pass/fail signals: test names with \"fail\", deprecation warnings, partial error messages. Keyword extraction cannot resolve these.\n\n### Mode 3: Hallucinated Failures (38% of parseable errors)\nWhen parseable, CWM hallucinates failures for passing patches (PASS→FAIL = 64/71 wrong parseable). The model's attempt to simulate execution makes it prone to generating plausible-looking error messages.\n\n---\n\n## 8. Suggested Figures\n\n### Figure A: Per-repo Unparseable Rate (Bar Chart)\n- X-axis: repos (scikit-learn, requests, django, ..., sphinx)\n- Y-axis: unparseable rate (0-100%)\n- Shows dramatic variation from ~0% to 100%\n- **Position**: Error Analysis subsection or Appendix\n\n### Figure B: Error Mode Breakdown (Stacked Bar or Pie)\n- Segments: no_keywords (77%), ambiguous_both (23%), other (<1%)\n- Or: token exhaustion vs keyword ambiguity vs degenerate repetition\n- **Position**: Error Analysis subsection\n\n### Figure C: CLS-CWM Gap Amplification (Grouped Bar)\n- X-axis: function-level 4B, function-level 8B, repo-level 4B\n- Y-axis: accuracy gap (pp)\n- Values: 1.24, 2.43, 24.31\n- **Position**: Main results section, key visualization for C1 claim\n\n### Figure D: Error Source Attribution (Stacked Bar)\n- Three segments: unparseable-default (57.5%), wrong parseable PASS→FAIL (38.3%), wrong parseable FAIL→PASS (4.2%)\n- **Position**: Error Analysis subsection\n\n### Figure E: CWM Scaling Non-benefit (Line Plot)\n- Two lines: CLS (88.43 → 89.39) vs CWM (87.19 → 86.96)\n- X-axis: 4B, 8B\n- **Position**: Discussion or Results\n\n---\n\n## 9. Paper Placement Recommendations\n\n| Data | Section | Rationale |\n|------|---------|-----------|\n| CLS-CWM gap amplification (§4 table) | **Results §5.3** (Repo-level) | Central finding, C1 claim |\n| Error mode breakdown (§2) | **Analysis §5.4** or **§6** | Explains WHY CWM fails |\n| Unparseable rate comparison (54-67% vs 0-1.3%) | **Results §5.3** | Headline comparison metric |\n| Parseable-only accuracy (42.88%) | **Analysis §5.4** | Shows CWM is anti-informative |\n| Correct-by-accident (38%) | **Analysis §5.4** | Deflates apparent CWM performance |\n| Scaling non-benefit (§6) | **Discussion §7** | Architectural implication |\n| Token exhaustion examples | **Appendix** | Qualitative illustration |\n| Per-repo breakdown | **Appendix** | Supporting detail |\n| Confusion matrix | **Appendix** | Full transparency |\n\n---\n\n## 10. Key Sentences for the Paper\n\n1. \"CWM accuracy drops from 87.19% at function-level to 58.04% at repo-level (−29pp), falling 14.92pp below the majority baseline, while CLS maintains above-baseline performance at both complexity levels.\"\n\n2. \"53.7-67.2% of CWM outputs are unparseable, with 77% of unparseable cases caused by token budget exhaustion — the model generates realistic pytest execution traces that consume the entire generation budget before reaching any verdict.\"\n\n3. \"Even among parseable CWM outputs, accuracy is only 42.88% — below random chance — indicating the model is anti-informative when it does produce interpretable predictions.\"\n\n4. \"57.5% of CWM errors stem from the unparseable-defaults-to-majority mechanism rather than incorrect predictions, suggesting the generative approach fundamentally cannot produce reliable execution simulations at repo scale.\"\n\n5. \"The CLS-CWM gap widens from 1.24pp (4B) to 2.43pp (8B) at function-level (p=0.025, d=1.24), and explodes to 24pp at repo-level, supporting the hypothesis that classification approaches scale better than generation for execution simulation.\"\n",
    "structuredPatch": [
      {
        "oldStart": 9,
        "oldLines": 9,
        "newStart": 9,
        "newLines": 9,
        "lines": [
          " | Metric | CWM v12 (s42) | CWM seed123 | CLS 4B best | CLS 8B (val-sel) | Majority BL |",
          " |--------|---------------|-------------|-------------|------------------|-------------|",
          " | **Accuracy** | 58.04% | 59.09% | 82.35% | **83.52%** | 72.96% |",
          "-| **F1 macro** | 51.67% | 43.43% | 74.74% | ⚠️ TBD | — |",
          "-| **F1 fail** | 34.12% | 13.67% | 60.87% | ⚠️ TBD | — |",
          "-| **F1 pass** | 69.22% | 73.19% | 88.60% | ⚠️ TBD | — |",
          "+| **F1 macro** | 51.67% | 43.43% | 74.74% | **77.50%** | — |",
          "+| **F1 fail** | 34.12% | 13.67% | 60.87% | **65.85%** | — |",
          "+| **F1 pass** | 69.22% | 73.19% | 88.60% | **89.14%** | — |",
          " | **Unparseable rate** | 53.7% | 67.2% | 1.3% | 0% | — |",
          " | **Parseable-only acc** | 42.88% | 42.68% | — | — | — |",
          " | **vs Majority (pp)** | −14.92 | −13.87 | +9.39 | +10.56 | 0 |"
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

_source line 20_

<details open><summary>🔧 Tool call — Edit · `toolu_01Abxf1tBVgQ6DFqo77wLCoC`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/error_analysis_data.md",
  "old_string": "> ⚠️ **D088 修正**: CLS 8B 改用 val-selected ckpt-1000 (test=83.52%)，不再用 test-best ckpt-400 (84.79%)。F1 macro/fail/pass 需从 ckpt-1000 eval 结果补填。",
  "new_string": "> **D088 修正**: CLS 8B 改用 val-selected ckpt-1000 (test=83.52%)，不再用 test-best ckpt-400 (84.79%)。F1 已从 `cls8b-s42-ckpt1000-test8192-eval` 补填：macro=77.50%, fail=65.85% (P=74.93%/R=58.73%), pass=89.14% (P=85.84%/R=92.72%)。Confusion: TP=6618, FP=1092, FN=520, TN=1554。"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "6dc15466-599b-4b7b-a2c5-c9ed2896e2f1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017LZJYgwjCsuLrqUDBi2ARW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 868,
      "cache_read_input_tokens": 28600,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 868
      },
      "output_tokens": 67,
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

_source line 21 · 2026-05-15T08:20:39.399Z_

<details><summary>↩ Tool result · `toolu_01Abxf1tBVgQ6DFqo77wLCoC`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/error_analysis_data.md has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "00948e7a-9300-4e4c-82ee-163d0d6befa0",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/error_analysis_data.md",
    "oldString": "> ⚠️ **D088 修正**: CLS 8B 改用 val-selected ckpt-1000 (test=83.52%)，不再用 test-best ckpt-400 (84.79%)。F1 macro/fail/pass 需从 ckpt-1000 eval 结果补填。",
    "newString": "> **D088 修正**: CLS 8B 改用 val-selected ckpt-1000 (test=83.52%)，不再用 test-best ckpt-400 (84.79%)。F1 已从 `cls8b-s42-ckpt1000-test8192-eval` 补填：macro=77.50%, fail=65.85% (P=74.93%/R=58.73%), pass=89.14% (P=85.84%/R=92.72%)。Confusion: TP=6618, FP=1092, FN=520, TN=1554。",
    "originalFile": "# CWM Error Analysis — Paper-Ready Data\n\n> Compiled: 2026-05-15. All numbers from registry experiments with matched environments (conda, transformers 4.57.6).\n\n---\n\n## 1. Headline Numbers: Repo-level CWM vs CLS\n\n| Metric | CWM v12 (s42) | CWM seed123 | CLS 4B best | CLS 8B (val-sel) | Majority BL |\n|--------|---------------|-------------|-------------|------------------|-------------|\n| **Accuracy** | 58.04% | 59.09% | 82.35% | **83.52%** | 72.96% |\n| **F1 macro** | 51.67% | 43.43% | 74.74% | **77.50%** | — |\n| **F1 fail** | 34.12% | 13.67% | 60.87% | **65.85%** | — |\n| **F1 pass** | 69.22% | 73.19% | 88.60% | **89.14%** | — |\n| **Unparseable rate** | 53.7% | 67.2% | 1.3% | 0% | — |\n| **Parseable-only acc** | 42.88% | 42.68% | — | — | — |\n| **vs Majority (pp)** | −14.92 | −13.87 | +9.39 | +10.56 | 0 |\n\n> ⚠️ **D088 修正**: CLS 8B 改用 val-selected ckpt-1000 (test=83.52%)，不再用 test-best ckpt-400 (84.79%)。F1 macro/fail/pass 需从 ckpt-1000 eval 结果补填。\n\n- CLS-CWM gap (4B apple-to-apple): CLS v5-conda 76.37% vs CWM v12 58.04% = **18.33pp**\n- CLS-CWM gap (best 4B CLS vs best 4B CWM): 82.35% vs 58.04% = **24.31pp**\n- CLS-CWM gap (8B CLS vs 4B CWM): 83.52% vs 58.04% = **25.48pp**\n- Both CWM seeds **below majority baseline** (72.96%) by ~14pp\n\n### Experiment References\n\n| exp_id | Model | Seed | Checkpoint | Eval Set |\n|--------|-------|------|------------|----------|\n| `repo-level-cwm-v12` | Qwen3-4B | 42 | ckpt-500 | test (n=9784) |\n| `repo-level-cwm-seed123-conda` | Qwen3-4B | 123 | ckpt-500 | test (n=9784) |\n| `repo-level-cls-v5` | Qwen3-4B | 42 | ckpt-4600 | test (n=9784) |\n| `repo-level-cls-v5-conda` | Qwen3-4B | 42 | ckpt-600 | test (n=9784) |\n| ~~`cls8b-s42-ckpt400-test8192-eval`~~ | ~~Qwen3-8B~~ | ~~42~~ | ~~ckpt-400~~ | ~~test@8192 (n=9784)~~ | ⚠️ superseded by D088 |\n| `cls8b-s42-ckpt1000-test8192-eval` | Qwen3-8B | 42 | ckpt-1000 | test@8192 (n=9784) | **primary (val-sel)** |\n\n---\n\n## 2. Error Mode Breakdown (v11 subset-500, config identical to v12)\n\nSource: `cwm_error_mode_analysis.md` (500-sample analysis from v11 ckpt-600, max_new_tokens=1024, max_seq_length=2048)\n\n### 2.1 Unparseable Rate: 75.2% (376/500)\n\n| Category | Count | % of Unparseable |\n|----------|-------|------------------|\n| Neither pass nor fail keywords (no_keywords) | 289 | 76.9% |\n| Both pass AND fail keywords (ambiguous_both) | 86 | 22.9% |\n| Only fail keywords | 1 | 0.3% |\n| Only pass keywords | 0 | 0.0% |\n\n\"Neither\" subcategories (289 samples):\n- pytest dot-progress bars: 48.1%\n- Command output / logs: 51.2%\n- All cut off at token budget before reaching verdict\n\n### 2.2 Error Source Attribution (167 total errors in subset-500)\n\n| Error Source | Count | % of Errors |\n|-------------|-------|-------------|\n| Unparseable → defaulted to PASS, but true=FAIL | 96 | **57.5%** |\n| Wrong parseable: true=PASS, pred=FAIL | 64 | 38.3% |\n| Wrong parseable: true=FAIL, pred=PASS | 7 | 4.2% |\n\n**57.5% of all errors come from the unparseable-defaults-to-majority mechanism**, not from model predictions.\n\n### 2.3 Token Budget Exhaustion\n\n| Statistic | All Samples | \"Neither\" Unparseable |\n|-----------|------------|----------------------|\n| Mean gen length (chars) | 3,398 | 3,773 |\n| Median | 3,308 | 3,933 |\n| Max | 7,582 | 6,582 |\n| Min | 722 | 1,002 |\n\n47.8% of all outputs exceed 3,500 chars. Typical pattern: model outputs `pytest -rA ...` → `test session starts` → hundreds of `.` dots → warnings → **cut off** (never reaches `passed/failed` summary).\n\n### 2.4 Parseable Prediction Quality (124/500 = 24.8%)\n\n| True Label | n | Accuracy |\n|-----------|---|----------|\n| FAIL | 39 | 82.1% |\n| PASS | 85 | 24.7% |\n| Overall | 124 | 42.7% |\n\nModel hallucinates failures: 64/71 wrong parseable predictions are PASS→FAIL.\n\n### 2.5 Input Truncation\n\n- 4.2% (21/500) truncated at max_seq_length=2048\n- Truncated accuracy: 38.1% vs non-truncated: 67.9%\n- 15/21 truncated samples also unparseable\n\n### 2.6 Confusion Matrix (v11 subset-500)\n\n| | Pred PASS | Pred FAIL |\n|---|----------|-----------|\n| True PASS | 301 (TP) | 64 (FP) |\n| True FAIL | 103 (FN) | 32 (TN) |\n\n---\n\n## 3. Per-repo Variation\n\nFrom `repo-level-cwm-v12` notes:\n- **Worst**: pytest — 25-42% accuracy\n- **Best**: requests — 64-84% accuracy\n\nPer-repo unparseable rate (from task background):\n- scikit-learn: ~0% unparseable\n- sphinx: 100% unparseable\n\nThe enormous per-repo variance reflects that CWM's ability to parse depends on the repo's test framework output format. Repos with concise pytest output (scikit-learn) are parseable; repos with verbose build/sphinx output are universally unparseable.\n\n---\n\n## 4. Cross-complexity Comparison (Function-level vs Repo-level)\n\n### Function-level CLS vs CWM (per-test, 1890 samples)\n\n| Config | CLS Acc | CWM Acc | Gap (pp) | p-value | Cohen's d |\n|--------|---------|---------|----------|---------|-----------|\n| 4B (5 seeds) | 88.43 ± 0.78 | 87.19 ± 0.37 | +1.24 | 0.025 | 1.24 |\n| 8B (3 seeds) | 89.39 ± 1.09 | 86.96 ± 0.72 | +2.43 | 0.007 | 4.97 |\n\n### Repo-level CLS vs CWM (9784 samples)\n\n| Config | CLS Acc | CWM Acc | Gap (pp) |\n|--------|---------|---------|----------|\n| 4B apple-to-apple | 76.37% | 58.04% | **+18.33** |\n| 4B best CLS vs CWM | 82.35% | 58.04% | **+24.31** |\n| 8B CLS (val-sel) vs 4B CWM | 83.52% | 58.04% | **+25.48** |\n\n### Gap Amplification Summary\n\n| Complexity Level | CLS-CWM Gap (pp) | CWM Unparseable |\n|-----------------|-------------------|-----------------|\n| Function-level (4B) | 1.24 | 0% |\n| Function-level (8B) | 2.43 | 0% |\n| Repo-level (4B) | 18-24 | 54-67% |\n\nThe gap explodes from ~1-2pp to ~24pp as code complexity increases from function-level to repo-level. This is the central C1 claim evidence.\n\n---\n\n## 5. \"Correct by Accident\" Analysis\n\nCWM's ~58-59% accuracy partly comes from unparseable outputs defaulting to majority class (PASS).\n\n- 38% of CWM \"correct\" predictions (in v12) are unparseable samples that happened to be PASS class\n- Parseable-only accuracy: 42.88% (v12 s42) / 42.68% (seed123)\n- Both parseable-only accuracies are below random (50%) — the model is **anti-informative** when parseable\n\n---\n\n## 6. Scaling Behavior (Function-level)\n\n| Method | 4B Mean | 8B Mean | Scaling Gain (pp) |\n|--------|---------|---------|-------------------|\n| CLS | 88.43 | 89.39 | **+0.96** |\n| CWM | 87.19 | 86.96 | **−0.23** |\n\nCLS benefits from scaling; CWM does not. CWM's bottleneck is generation overhead, not model capacity. Gap widens: 1.24pp (4B) → 2.43pp (8B), probability of widening p=0.988.\n\n---\n\n## 7. Three Inherent CWM Failure Modes\n\n### Mode 1: Token Budget Exhaustion (primary, ~77% of unparseable)\nCWM must generate ~3400 chars of execution trace to reach a verdict vs CLS's 1-2 tokens. The model produces realistic pytest sessions with dots, warnings, and file paths that consume the entire budget before reaching any pass/fail summary.\n\n### Mode 2: Keyword Ambiguity (~23% of unparseable)\nRealistic execution traces contain mixed pass/fail signals: test names with \"fail\", deprecation warnings, partial error messages. Keyword extraction cannot resolve these.\n\n### Mode 3: Hallucinated Failures (38% of parseable errors)\nWhen parseable, CWM hallucinates failures for passing patches (PASS→FAIL = 64/71 wrong parseable). The model's attempt to simulate execution makes it prone to generating plausible-looking error messages.\n\n---\n\n## 8. Suggested Figures\n\n### Figure A: Per-repo Unparseable Rate (Bar Chart)\n- X-axis: repos (scikit-learn, requests, django, ..., sphinx)\n- Y-axis: unparseable rate (0-100%)\n- Shows dramatic variation from ~0% to 100%\n- **Position**: Error Analysis subsection or Appendix\n\n### Figure B: Error Mode Breakdown (Stacked Bar or Pie)\n- Segments: no_keywords (77%), ambiguous_both (23%), other (<1%)\n- Or: token exhaustion vs keyword ambiguity vs degenerate repetition\n- **Position**: Error Analysis subsection\n\n### Figure C: CLS-CWM Gap Amplification (Grouped Bar)\n- X-axis: function-level 4B, function-level 8B, repo-level 4B\n- Y-axis: accuracy gap (pp)\n- Values: 1.24, 2.43, 24.31\n- **Position**: Main results section, key visualization for C1 claim\n\n### Figure D: Error Source Attribution (Stacked Bar)\n- Three segments: unparseable-default (57.5%), wrong parseable PASS→FAIL (38.3%), wrong parseable FAIL→PASS (4.2%)\n- **Position**: Error Analysis subsection\n\n### Figure E: CWM Scaling Non-benefit (Line Plot)\n- Two lines: CLS (88.43 → 89.39) vs CWM (87.19 → 86.96)\n- X-axis: 4B, 8B\n- **Position**: Discussion or Results\n\n---\n\n## 9. Paper Placement Recommendations\n\n| Data | Section | Rationale |\n|------|---------|-----------|\n| CLS-CWM gap amplification (§4 table) | **Results §5.3** (Repo-level) | Central finding, C1 claim |\n| Error mode breakdown (§2) | **Analysis §5.4** or **§6** | Explains WHY CWM fails |\n| Unparseable rate comparison (54-67% vs 0-1.3%) | **Results §5.3** | Headline comparison metric |\n| Parseable-only accuracy (42.88%) | **Analysis §5.4** | Shows CWM is anti-informative |\n| Correct-by-accident (38%) | **Analysis §5.4** | Deflates apparent CWM performance |\n| Scaling non-benefit (§6) | **Discussion §7** | Architectural implication |\n| Token exhaustion examples | **Appendix** | Qualitative illustration |\n| Per-repo breakdown | **Appendix** | Supporting detail |\n| Confusion matrix | **Appendix** | Full transparency |\n\n---\n\n## 10. Key Sentences for the Paper\n\n1. \"CWM accuracy drops from 87.19% at function-level to 58.04% at repo-level (−29pp), falling 14.92pp below the majority baseline, while CLS maintains above-baseline performance at both complexity levels.\"\n\n2. \"53.7-67.2% of CWM outputs are unparseable, with 77% of unparseable cases caused by token budget exhaustion — the model generates realistic pytest execution traces that consume the entire generation budget before reaching any verdict.\"\n\n3. \"Even among parseable CWM outputs, accuracy is only 42.88% — below random chance — indicating the model is anti-informative when it does produce interpretable predictions.\"\n\n4. \"57.5% of CWM errors stem from the unparseable-defaults-to-majority mechanism rather than incorrect predictions, suggesting the generative approach fundamentally cannot produce reliable execution simulations at repo scale.\"\n\n5. \"The CLS-CWM gap widens from 1.24pp (4B) to 2.43pp (8B) at function-level (p=0.025, d=1.24), and explodes to 24pp at repo-level, supporting the hypothesis that classification approaches scale better than generation for execution simulation.\"\n",
    "structuredPatch": [
      {
        "oldStart": 16,
        "oldLines": 7,
        "newStart": 16,
        "newLines": 7,
        "lines": [
          " | **Parseable-only acc** | 42.88% | 42.68% | — | — | — |",
          " | **vs Majority (pp)** | −14.92 | −13.87 | +9.39 | +10.56 | 0 |",
          " ",
          "-> ⚠️ **D088 修正**: CLS 8B 改用 val-selected ckpt-1000 (test=83.52%)，不再用 test-best ckpt-400 (84.79%)。F1 macro/fail/pass 需从 ckpt-1000 eval 结果补填。",
          "+> **D088 修正**: CLS 8B 改用 val-selected ckpt-1000 (test=83.52%)，不再用 test-best ckpt-400 (84.79%)。F1 已从 `cls8b-s42-ckpt1000-test8192-eval` 补填：macro=77.50%, fail=65.85% (P=74.93%/R=58.73%), pass=89.14% (P=85.84%/R=92.72%)。Confusion: TP=6618, FP=1092, FN=520, TN=1554。",
          " ",
          " - CLS-CWM gap (4B apple-to-apple): CLS v5-conda 76.37% vs CWM v12 58.04% = **18.33pp**",
          " - CLS-CWM gap (best 4B CLS vs best 4B CWM): 82.35% vs 58.04% = **24.31pp**"
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

Now sync to the `_project/data/` copy.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "38306774-3338-45c5-a253-8fc94ce8fc30",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqp88xFeHC4uLwT3zKQQMF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 448,
      "cache_read_input_tokens": 29468,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 448
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

<details open><summary>🔧 Tool call — Bash · `toolu_011Nhuw8DniWh8p1nrDx7TXA`</summary>

```json
{
  "command": "cp /home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/error_analysis_data.md /home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/artifacts/_project/data/error_analysis_data.md",
  "description": "Sync error_analysis_data.md to _project/data copy"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "60dbc5a2-a37e-4304-ac32-a17b67c3935d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqp88xFeHC4uLwT3zKQQMF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 448,
      "cache_read_input_tokens": 29468,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 448
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

_source line 24 · 2026-05-15T08:20:43.592Z_

<details><summary>↩ Tool result · `toolu_011Nhuw8DniWh8p1nrDx7TXA`</summary>

```text
(Bash completed with no output)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "a52f0c89-8e25-454c-8d02-38bf56c1e574",
  "tool_use_result": {
    "stdout": "",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": true
  }
}
```

</details>

---

### Assistant

_source line 25_

替换了 4 处：

| 位置 | 原值 | 新值 |
|------|------|------|
| §1 表格 F1 macro 列 (行12) | `⚠️ TBD` | `**77.50%**` |
| §1 表格 F1 fail 列 (行13) | `⚠️ TBD` | `**65.85%**` |
| §1 表格 F1 pass 列 (行14) | `⚠️ TBD` | `**89.14%**` |
| §1 D088 修正注释 (行19) | `⚠️ ... 需从 ckpt-1000 eval 结果补填` | 完整 F1/P/R/Confusion 数据，移除 ⚠️ |

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "uuid": "77525197-e050-4c55-aaab-191dd26427f5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012mLKzcSjsnPCHC7oD5EEpV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 303,
      "cache_read_input_tokens": 29916,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 303
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

_source line 26_

替换了 4 处：

| 位置 | 原值 | 新值 |
|------|------|------|
| §1 表格 F1 macro 列 (行12) | `⚠️ TBD` | `**77.50%**` |
| §1 表格 F1 fail 列 (行13) | `⚠️ TBD` | `**65.85%**` |
| §1 表格 F1 pass 列 (行14) | `⚠️ TBD` | `**89.14%**` |
| §1 D088 修正注释 (行19) | `⚠️ ... 需从 ckpt-1000 eval 结果补填` | 完整 F1/P/R/Confusion 数据，移除 ⚠️ |

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 45558,
  "duration_api_ms": 46288,
  "num_turns": 8,
  "stop_reason": "end_turn",
  "session_id": "999107ac-9036-4971-afb1-85d3fdfd182d",
  "total_cost_usd": 0.266256,
  "usage": {
    "input_tokens": 12,
    "cache_creation_input_tokens": 18772,
    "cache_read_input_tokens": 193922,
    "output_tokens": 2037,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 18772,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 227,
        "cache_read_input_tokens": 29916,
        "cache_creation_input_tokens": 303,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 303
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 900,
      "outputTokens": 17,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.000985,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 12,
      "outputTokens": 2037,
      "cacheReadInputTokens": 193922,
      "cacheCreationInputTokens": 18772,
      "webSearchRequests": 0,
      "costUSD": 0.265271,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "cc2d1dce-3626-41f2-a77e-f769d41bbd3b"
}
```

</details>

---
