# cpu alpha crit seed audit — Part 1 of 2

**When Self-Consistency Fails for NER: Degeneracy, Signal Collapse, and the Correlation-Selection Gap** · Worker execution logs

[Transcript overview](../cpu-alpha-crit-seed-audit.md) · [Part 2 →](part-002.md) · [Structured JSON](../../../sessions/1c/1cff758a475aa96fb6b5.json)

## Before a recorded user message

## Before a recorded user message

158 recorded events


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
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
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
    "mcp__agent-ml-research__read_registry",
    "mcp__agent-ml-research__register_artifact",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__ssh_execute",
    "mcp__agent-ml-research__ssh_read_only",
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
  "uuid": "7e23b306-9e3d-4271-a30b-76e5f99e12cd",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/memory/"
  },
  "fast_mode_state": "off"
}
```

---


### Assistant

_source line 3_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the current α_crit table and checking the registry for relevant experiments.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "147d716d-ba36-4e7c-80b8-56b6ca22ebf5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XtyCp8AyT3x65MEW5R2oMy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12848,
      "cache_read_input_tokens": 11701,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12848
      },
      "output_tokens": 37,
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


### Runtime record

_source line 4_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed_warning",
    "resetsAt": 1779580800,
    "rateLimitType": "seven_day",
    "utilization": 0.8,
    "isUsingOverage": false,
    "surpassedThreshold": 0.75
  },
  "uuid": "8a3103ab-d33a-45fa-8502-22d7f14f27a2",
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630"
}
```

---


### Assistant

_source line 5_

开始执行 α_crit 数据源验证任务。先并行读取当前表格和查询注册表。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "cfa650e5-c59e-472a-886d-754cdc091b4a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XtyCp8AyT3x65MEW5R2oMy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12848,
      "cache_read_input_tokens": 11701,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12848
      },
      "output_tokens": 37,
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01G3WFDTBwPGtwua6mJ4ZMPy`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__detect_image",
  "max_results": 6
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "3f5f3e29-42e9-4415-80cc-654586a6261d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XtyCp8AyT3x65MEW5R2oMy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12848,
      "cache_read_input_tokens": 11701,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12848
      },
      "output_tokens": 37,
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

_source line 7 · 2026-05-21T09:27:02.860Z_

<details><summary>↩ Tool result · `toolu_01G3WFDTBwPGtwua6mJ4ZMPy`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_registry"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_project_file"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__ssh_read_only"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__ssh_execute"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__detect_image"
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
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "e24985df-3a6b-4e03-9d0e-5569f3236089",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__ssh_execute",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__detect_image"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__detect_image",
    "total_deferred_tools": 29
  }
}
```

</details>

---


### Assistant

_source line 8_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the current α_crit table and query the registry in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "6063d94c-406d-4a85-bd43-093f6a9d3513",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Kjexwa3gJrLWimvBhoAKYJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2236,
      "cache_read_input_tokens": 24549,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2236
      },
      "output_tokens": 42,
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

<details open><summary>🔧 Tool call — Read · `toolu_01UWV5Fc5i3YVURB5xF12HKe`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/alpha_crit_table.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "6315724d-d5d6-4152-99af-ba2f22ea5bce",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Kjexwa3gJrLWimvBhoAKYJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2236,
      "cache_read_input_tokens": 24549,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2236
      },
      "output_tokens": 42,
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

_source line 10 · 2026-05-21T09:27:06.621Z_

<details><summary>↩ Tool result · `toolu_01UWV5Fc5i3YVURB5xF12HKe`</summary>

````text
1	## α_crit Entity Selection Bound
2	
3	### Main Table (T=1.0, multi-seed averages)
4	
5	| Dataset | π_MV | α_crit | α_obs | Gap (α − α_crit) | Δ_SC (pp) | Degeneracy | Bound Predicts | Empirical |
6	|---------|------|--------|-------|-------------------|-----------|------------|----------------|-----------|
7	| FewNERD | 0.6561 | 0.4882 | 0.6311 | +0.1429 | **−9.21** | 12.3% | Yes | **No** |
8	| CoNLL   | 0.8938 | 0.8079 | 0.8743 | +0.0664 | **−1.37** | 63.0% | Yes | **No** |
9	| SciERC  | 0.6138 | 0.4428 | 0.6069 | +0.1641 | **−3.03** | 20.3% | Yes | **No** |
10	
11	- **π_MV**: Entity-level majority voting F1 (from multi-seed entity construction)
12	- **α_obs**: Mean individual sample F1 (`sample_f1_mean` from `report.json`)
13	- **Δ_SC**: MV F1 − greedy F1 (positive = SC aggregation wins; all negative here)
14	- **Degeneracy**: Fraction of entities with identical outputs across all n=8 samples
15	
16	### Detailed Baselines
17	
18	| Dataset | Greedy | MV | θ2n Select | LP Select | Oracle | Headroom |
19	|---------|--------|----|------------|-----------|--------|----------|
20	| FewNERD | 0.7482 | 0.6561 | 0.7571 | 0.7619 | 0.8747 | 12.65 pp |
21	| CoNLL   | 0.9075 | 0.8938 | 0.8966 | 0.9006 | 0.9460 | 3.85 pp |
22	| SciERC  | 0.6441 | 0.6138 | 0.6516 | 0.6469 | 0.7746 | 13.06 pp |
23	
24	### Derivation
25	
26	```
27	α_crit = π_MV / (2 − π_MV)
28	```
29	
30	- When α > α_crit: SC aggregation should improve over individual samples (agreement signal is informative)
31	- When α < α_crit: SC aggregation hurts (information loss exceeds agreement gain)
32	
33	### Key Finding: SC Universally Fails for Structured NER
34	
35	The bound predicts SC effectiveness for all three datasets (α > α_crit everywhere). However, **all three datasets violate this prediction**: entity-level MV is 1.4–9.2 pp worse than greedy across all settings.
36	
37	This universal failure has two causes:
38	
39	1. **Degeneracy** (CoNLL): 63% of entities produce identical outputs across all 8 samples. The agreement signal carries no discriminative power. The degeneracy-adjusted bound correctly predicts failure:
40	
41	```
42	α_crit_effective = α_crit / (1 − δ)
43	```
44	
45	For CoNLL: 0.8079 / (1 − 0.63) = 2.184 > 1.0 → correctly predicts SC cannot work.
46	
47	2. **Entity-level span mismatch** (FewNERD, SciERC): Even after degeneracy adjustment, the bound still predicts SC should work (FewNERD: α_crit_eff = 0.557 < α_obs = 0.631; SciERC: α_crit_eff = 0.556 < α_obs = 0.607). The failure is structural: entity-level MV combines entities from different samples, and when span boundaries differ across samples, the aggregated output introduces errors absent from any individual sample. This structural mismatch is not captured by the independence assumption underlying the α_crit bound.
48	
49	**Implication**: The α_crit bound, derived for classification-style SC, does not transfer to structured IE where outputs are sets of spans. Sample-level selection (LP: +1.36 pp on FewNERD) can succeed where entity-level aggregation fails, because selection preserves internal span consistency.
50	
51	### Data Sources
52	
53	- FewNERD: 3 seeds (123, 456, 789), n_instances=32,565
54	- CoNLL: 2 seeds (123, 456), n_instances=2,756
55	- SciERC: 2 seeds (456, 789), n_instances=529
56	- Greedy/MV/Oracle from entity construction experiments; selection F1 from `full_signal_analysis.json`
57	
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "d31ef2cc-e68d-46bf-a04f-9255e178a59d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/alpha_crit_table.md",
      "content": "## α_crit Entity Selection Bound\n\n### Main Table (T=1.0, multi-seed averages)\n\n| Dataset | π_MV | α_crit | α_obs | Gap (α − α_crit) | Δ_SC (pp) | Degeneracy | Bound Predicts | Empirical |\n|---------|------|--------|-------|-------------------|-----------|------------|----------------|-----------|\n| FewNERD | 0.6561 | 0.4882 | 0.6311 | +0.1429 | **−9.21** | 12.3% | Yes | **No** |\n| CoNLL   | 0.8938 | 0.8079 | 0.8743 | +0.0664 | **−1.37** | 63.0% | Yes | **No** |\n| SciERC  | 0.6138 | 0.4428 | 0.6069 | +0.1641 | **−3.03** | 20.3% | Yes | **No** |\n\n- **π_MV**: Entity-level majority voting F1 (from multi-seed entity construction)\n- **α_obs**: Mean individual sample F1 (`sample_f1_mean` from `report.json`)\n- **Δ_SC**: MV F1 − greedy F1 (positive = SC aggregation wins; all negative here)\n- **Degeneracy**: Fraction of entities with identical outputs across all n=8 samples\n\n### Detailed Baselines\n\n| Dataset | Greedy | MV | θ2n Select | LP Select | Oracle | Headroom |\n|---------|--------|----|------------|-----------|--------|----------|\n| FewNERD | 0.7482 | 0.6561 | 0.7571 | 0.7619 | 0.8747 | 12.65 pp |\n| CoNLL   | 0.9075 | 0.8938 | 0.8966 | 0.9006 | 0.9460 | 3.85 pp |\n| SciERC  | 0.6441 | 0.6138 | 0.6516 | 0.6469 | 0.7746 | 13.06 pp |\n\n### Derivation\n\n```\nα_crit = π_MV / (2 − π_MV)\n```\n\n- When α > α_crit: SC aggregation should improve over individual samples (agreement signal is informative)\n- When α < α_crit: SC aggregation hurts (information loss exceeds agreement gain)\n\n### Key Finding: SC Universally Fails for Structured NER\n\nThe bound predicts SC effectiveness for all three datasets (α > α_crit everywhere). However, **all three datasets violate this prediction**: entity-level MV is 1.4–9.2 pp worse than greedy across all settings.\n\nThis universal failure has two causes:\n\n1. **Degeneracy** (CoNLL): 63% of entities produce identical outputs across all 8 samples. The agreement signal carries no discriminative power. The degeneracy-adjusted bound correctly predicts failure:\n\n```\nα_crit_effective = α_crit / (1 − δ)\n```\n\nFor CoNLL: 0.8079 / (1 − 0.63) = 2.184 > 1.0 → correctly predicts SC cannot work.\n\n2. **Entity-level span mismatch** (FewNERD, SciERC): Even after degeneracy adjustment, the bound still predicts SC should work (FewNERD: α_crit_eff = 0.557 < α_obs = 0.631; SciERC: α_crit_eff = 0.556 < α_obs = 0.607). The failure is structural: entity-level MV combines entities from different samples, and when span boundaries differ across samples, the aggregated output introduces errors absent from any individual sample. This structural mismatch is not captured by the independence assumption underlying the α_crit bound.\n\n**Implication**: The α_crit bound, derived for classification-style SC, does not transfer to structured IE where outputs are sets of spans. Sample-level selection (LP: +1.36 pp on FewNERD) can succeed where entity-level aggregation fails, because selection preserves internal span consistency.\n\n### Data Sources\n\n- FewNERD: 3 seeds (123, 456, 789), n_instances=32,565\n- CoNLL: 2 seeds (123, 456), n_instances=2,756\n- SciERC: 2 seeds (456, 789), n_instances=529\n- Greedy/MV/Oracle from entity construction experiments; selection F1 from `full_signal_analysis.json`\n",
      "numLines": 57,
      "startLine": 1,
      "totalLines": 57
    }
  }
}
````

</details>

---


### Tool call

_source line 11_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01CWhPJMPUSbTbAhEHXRmiHT`</summary>

```json
{
  "project": "struct_self_consist_ie",
  "limit": 0,
  "fields": [
    "*"
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
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "77ddf1e5-7842-4b2f-a7bd-c5b3b1bd34e1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Kjexwa3gJrLWimvBhoAKYJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2236,
      "cache_read_input_tokens": 24549,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2236
      },
      "output_tokens": 42,
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

_source line 12 · 2026-05-21T09:27:08.058Z_

<details><summary>↩ Tool result · `toolu_01CWhPJMPUSbTbAhEHXRmiHT`</summary>

```text
Error: result (422,827 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/6986ae13-ffc9-44c1-9a46-461b58b60630/tool-results/mcp-agent-ml-research-read_registry-1779355628042.txt.
Format: JSON with schema: {result: string}
Use offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.
REQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:
- You MUST read the content from the file at /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/6986ae13-ffc9-44c1-9a46-461b58b60630/tool-results/mcp-agent-ml-research-read_registry-1779355628042.txt in sequential chunks until 100% of the content has been read.
- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.
- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "4a456ab4-b392-4d2c-b2b4-105026ecadfc",
  "tool_use_result": {
    "content": "Error: result (422,827 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/6986ae13-ffc9-44c1-9a46-461b58b60630/tool-results/mcp-agent-ml-research-read_registry-1779355628042.txt.\nFormat: JSON with schema: {result: string}\nUse offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.\nREQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:\n- You MUST read the content from the file at /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/6986ae13-ffc9-44c1-9a46-461b58b60630/tool-results/mcp-agent-ml-research-read_registry-1779355628042.txt in sequential chunks until 100% of the content has been read.\n- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.\n- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"exp_conll_mf4_v2_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:34:10.294Z\", \"updated_at\": \"2026-05-21T09:11:29.209Z\", \"hypothesis\": \"MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). 3-seed set with exp_conll_t10_s42.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/conll_mf4v2_seed456/\\\"\", \"server\": \"autodl-5090-b\", \"gpu\": [\"cuda:1\"], \"pid\": \"334155\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_mf4_v2_s456.log\", \"submitted_at\": \"2026-05-21T08:33:55.428Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set (3453 instances, N=8)\", \"wall_clock_seconds\": 2253.8, \"gpu_hours\": 0.63}, \"checkpoint_path\": \"output/conll_mf4v2_seed456/\", \"metrics\": {\"greedy_f1\": 0.907, \"oracle_f1\": 0.9426, \"oracle_headroom\": 0.0357, \"fleiss_kappa_mean\": 0.768, \"soft_jaccard_mean\": 0.892, \"rho_SJ_full\": 0.4803, \"rho_kappa_full\": 0.4638, \"rho_SJ_cond\": 0.4513, \"rho_kappa_cond\": 0.425, \"logprob_rho_full\": 0.3213, \"logprob_rho_cond\": 0.3723, \"logprob_auroc_full\": 0.7569, \"logprob_auroc_cond\": 0.8221, \"sample_f1_mean\": 0.8737, \"sample_f1_pct_zero\": 7.08, \"structural_beats_surface\": true, \"rho_advantage\": 0.0166, \"verdict\": \"PASS\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T09:11:29.209Z\"}, \"exp_conll_mf4_v2_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:34:09.147Z\", \"updated_at\": \"2026-05-21T09:11:26.284Z\", \"hypothesis\": \"MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). 3-seed set with exp_conll_t10_s42.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/conll_mf4v2_seed123/\\\"\", \"server\": \"autodl-5090-b\", \"gpu\": [\"cuda:0\"], \"pid\": \"334013\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_mf4_v2_s123.log\", \"submitted_at\": \"2026-05-21T08:33:53.084Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set (3453 instances, N=8)\", \"wall_clock_seconds\": 2253.2, \"gpu_hours\": 0.63}, \"checkpoint_path\": \"output/conll_mf4v2_seed123/\", \"metrics\": {\"greedy_f1\": 0.9083, \"oracle_f1\": 0.9527, \"oracle_headroom\": 0.0444, \"fleiss_kappa_mean\": 0.762, \"soft_jaccard_mean\": 0.886, \"rho_SJ_full\": 0.4628, \"rho_kappa_full\": 0.4457, \"rho_SJ_cond\": 0.414, \"rho_kappa_cond\": 0.3887, \"logprob_rho_full\": 0.3281, \"logprob_rho_cond\": 0.367, \"logprob_auroc_full\": 0.7621, \"logprob_auroc_cond\": 0.8198, \"sample_f1_mean\": 0.8744, \"sample_f1_pct_zero\": 7.05, \"structural_beats_surface\": true, \"rho_advantage\": 0.0171, \"verdict\": \"PASS\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T09:11:26.284Z\"}, \"exp_frontier_sc_deepseek\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T06:50:26.022Z\", \"updated_at\": \"2026-05-21T09:10:40.589Z\", \"hypothesis\": \"Frontier model DeepSeek Chat on FewNERD SC (200 inst, N=8, T=1.0): 4-family cross-validation of correlation-selection gap universality.\", \"spec\": {\"command\": \"python -u code/run_frontier_sc.py --model deepseek/deepseek-chat --base_url http://47.94.22.126/v1 --dataset fewnerd --n_instances 200 --n_samples 8 --temperature 1.0 --output_dir output/frontier_sc_deepseek/ --max_workers 4\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 200, \"model_name\": \"deepseek/deepseek-chat\", \"seed\": 42}, \"checkpoint_path\": \"output/frontier_sc_deepseek/\", \"log_path\": \"logs/frontier_sc_deepseek.log\", \"metrics\": {\"greedy_f1\": 0.3992, \"mv_f1\": 0.4243, \"oracle_f1\": 0.714, \"degeneracy_rate\": 0.055, \"agreement_rho\": 0.2051, \"fleiss_kappa_rho\": 0.1471, \"sj_rho\": 0.1635, \"mv_gain_over_greedy\": 0.0251, \"selection_gap\": 0.2897, \"parse_failure_count\": 751, \"total_api_calls\": 1600, \"elapsed_s\": 4043.7}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T09:10:40.589Z\"}, \"exp_e2_pretrained_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T07:18:21.189Z\", \"updated_at\": \"2026-05-21T09:10:13.722Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path /root/autodl-tmp/.hf_cache/Qwen2.5-7B-Instruct/ --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/e2_pretrained_scierc/\\\"\", \"server\": \"autodl-5090-c\", \"gpu\": [\"cuda:3\"], \"pid\": \"294269\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_e2_pretrained_scierc.log\", \"submitted_at\": \"2026-05-21T07:18:20.538Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data/\", \"data_count\": 100, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"pretrained_base\", \"eval_data\": \"scierc test set (100 instances, N=8)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/e2_pretrained_scierc/\", \"wall_clock_seconds\": 6705.7, \"gpu_hours\": 1.86}, \"hypothesis\": \"E2 pre-trained baseline: Qwen2.5-7B-Instruct (unfinetuned) on SciERC SC pipeline N=8 T=1.0. Third dataset for E2 baseline, validates whether correlation-selection gap exists without task-specific fine-tuning across all 3 NER benchmarks.\", \"conclusion\": \"negative\", \"metrics\": {\"greedy_f1\": 0.2418, \"oracle_f1\": 0.3888, \"oracle_headroom\": 0.147, \"fleiss_kappa_mean\": 0.223, \"soft_jaccard_mean\": 0.473, \"rho_SJ_full\": 0.2193, \"rho_kappa_full\": 0.2516, \"rho_SJ_cond\": 0.1987, \"rho_kappa_cond\": 0.1953, \"logprob_rho_full\": 0.078, \"logprob_auroc_full\": 0.5412, \"logprob_rho_cond\": 0.1895, \"logprob_auroc_cond\": 0.5527, \"sample_f1_mean\": 0.2272, \"sample_f1_pct_zero\": 46.29, \"structural_beats_surface\": false, \"verdict\": \"FAIL\", \"warning\": \">30% samples F1=0\"}, \"checkpoint_path\": \"output/e2_pretrained_scierc/\", \"completed_at\": \"2026-05-21T09:10:06.217Z\"}, \"exp_conll_n16_s456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:05:07.022Z\", \"updated_at\": \"2026-05-21T09:10:12.516Z\", \"hypothesis\": \"CoNLL N=16 (seed=456, v2): retry after previous failure on 5090. Third seed for 3-seed statistical power on CoNLL-2003 N=16.\", \"parent\": \"exp_conll_n16_s456\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/conll_n16_seed456_v2/\\\"\", \"server\": \"autodl-5090-c\", \"gpu\": [\"cuda:2\"], \"pid\": \"293990\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s456_v2.log\", \"submitted_at\": \"2026-05-21T07:18:17.355Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set (3453 instances, N=16)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_seed456_v2/\", \"wall_clock_seconds\": 6703.7, \"gpu_hours\": 1.86}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.9076, \"oracle_f1\": 0.955, \"oracle_headroom\": 0.0474, \"fleiss_kappa_mean\": 0.8, \"soft_jaccard_mean\": 0.8965, \"rho_SJ_full\": 0.4791, \"rho_kappa_full\": 0.4697, \"rho_SJ_cond\": 0.4481, \"rho_kappa_cond\": 0.4268, \"logprob_rho_full\": 0.3137, \"logprob_rho_cond\": 0.373, \"logprob_auroc_full\": 0.7524, \"logprob_auroc_cond\": 0.8236, \"sample_f1_mean\": 0.8736, \"sample_f1_pct_zero\": 7.03, \"verdict\": \"PASS\"}, \"completed_at\": \"2026-05-21T09:10:01.095Z\", \"checkpoint_path\": \"output/conll_n16_seed456_v2/\"}, \"exp_conll_n16_s123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:05:03.921Z\", \"updated_at\": \"2026-05-21T09:10:11.273Z\", \"hypothesis\": \"CoNLL N=16 (seed=123, v2): retry after previous failure on 5090 (damaged checkpoint). Extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003.\", \"parent\": \"exp_conll_n16_s123\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/conll_n16_seed123_v2/\\\"\", \"server\": \"autodl-5090-c\", \"gpu\": [\"cuda:1\"], \"pid\": \"293577\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s123_v2.log\", \"submitted_at\": \"2026-05-21T07:18:14.095Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set (3453 instances, N=16)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_seed123_v2/\", \"wall_clock_seconds\": 6702.6, \"gpu_hours\": 1.86}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.9071, \"oracle_f1\": 0.9625, \"oracle_headroom\": 0.0554, \"fleiss_kappa_mean\": 0.767, \"soft_jaccard_mean\": 0.877, \"rho_SJ_full\": 0.4567, \"rho_kappa_full\": 0.4469, \"rho_SJ_cond\": 0.4174, \"rho_kappa_cond\": 0.3936, \"logprob_rho_full\": 0.3456, \"logprob_rho_cond\": 0.375, \"logprob_auroc_full\": 0.7742, \"logprob_auroc_cond\": 0.8258, \"sample_f1_mean\": 0.8676, \"sample_f1_pct_zero\": 7.52, \"verdict\": \"PASS\"}, \"completed_at\": \"2026-05-21T09:09:56.663Z\", \"checkpoint_path\": \"output/conll_n16_seed123_v2/\"}, \"exp_scierc_mf4_v2_s42\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T09:01:28.521Z\", \"updated_at\": \"2026-05-21T09:08:40.545Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/scierc_mf4v2_seed42/\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"18393\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_scierc_mf4_v2_s42.log\", \"submitted_at\": \"2026-05-21T09:08:39.861Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"exp_frontier_sc_claude_sonnet4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T06:20:27.878Z\", \"updated_at\": \"2026-05-21T08:58:17.224Z\", \"hypothesis\": \"Frontier model Claude Sonnet 4 on FewNERD SC (200 instances, N=8, T=1.0): if correlation-selection gap persists across model families (GPT + Claude + Gemini + DeepSeek), the finding is universal and not model-specific.\", \"spec\": {\"command\": \"python -u code/run_frontier_sc.py --model anthropic/claude-sonnet-4 --base_url http://47.94.22.126/v1 --dataset fewnerd --data_dir data/fewnerd/ --n_instances 200 --n_samples 8 --temperature 1.0 --output_dir output/frontier_sc_claude_sonnet4/ --max_tokens 4096\", \"server\": \"autodl-5090\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 200, \"model_name\": \"anthropic/claude-sonnet-4\", \"seed\": 42, \"pid\": 6302, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/frontier_sc_claude_sonnet4.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/frontier_sc_claude_sonnet4/\", \"checkpoint_source\": \"API (http://47.94.22.126/v1)\", \"eval_data\": \"fewnerd test set (200 instances, N=8, T=1.0)\", \"matching\": \"text+type (case-insensitive, no offset)\", \"note\": \"v2: fixed from offset-based to text-based entity matching for API models\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.6068, \"mv_f1\": 0.6226, \"oracle_f1\": 0.6544, \"degeneracy_rate\": 0.74, \"selection_gap\": 0.0318, \"parse_failures\": 103, \"api_calls\": 1600, \"wall_clock_seconds\": 6118, \"instances\": 200}, \"completed_at\": \"2026-05-21T08:58:17.224Z\"}, \"exp_e2_pretrained_conll\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:52:08.180Z\", \"updated_at\": \"2026-05-21T08:56:26.187Z\", \"hypothesis\": \"E2 pre-trained baseline: Qwen2.5-7B-Instruct (unfinetuned) on CoNLL SC pipeline N=8 T=1.0. Cross-dataset validation of pre-trained baseline. Together with FewNERD baseline, shows whether fine-tuning modulates the gap magnitude.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path /root/autodl-tmp/models/Qwen2.5-7B-Instruct/Qwen/Qwen2___5-7B-Instruct --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/e2_pretrained_conll/\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"7939\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp_e2_pretrained_conll.log\", \"submitted_at\": \"2026-05-21T06:59:13.431Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"pretrained_base\", \"eval_data\": \"conll2003\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/e2_pretrained_conll/\", \"wall_clock_seconds\": 5840.6, \"gpu_hours\": 1.62}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T08:36:34.020Z\"}, \"exp_frontier_sc_gpt55_fewnerd_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:48:24.698Z\", \"updated_at\": \"2026-05-21T08:36:36.829Z\", \"hypothesis\": \"Frontier model GPT-5.5 on FewNERD SC (200 instances, N=8, T=1.0): if correlation-selection gap persists in frontier models, the finding is fundamental and not a model capability limitation. Previous attempt failed due to API credit exhaustion.\", \"parent\": \"exp_b_frontier_sc_fewnerd\", \"spec\": {\"command\": \"python -u code/run_frontier_sc.py --model gpt-5.5 --base_url http://47.94.22.126/v1 --n_instances 200 --n_samples 8 --temperature 1.0 --seed 42 --max_workers 4\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 200, \"model_name\": \"gpt-5.5\", \"seed\": 42, \"checkpoint_source\": \"openai/gpt-5.5 (API)\", \"eval_data\": \"fewnerd test set (200 instances)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/frontier_sc_gpt55_fewnerd_v2/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/frontier_sc_gpt55_fewnerd_v2.log\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.6382, \"mv_f1\": 0.6521, \"oracle_f1\": 0.7203, \"degeneracy_rate\": 0.5, \"rho_agreement\": 0.3551, \"rho_fk\": 0.3515, \"rho_sj\": 0.3461, \"instances\": 200}, \"completed_at\": \"2026-05-21T08:36:36.829Z\"}, \"exp_fewnerd_mf4_v2_s456\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:34:07.139Z\", \"updated_at\": \"2026-05-21T08:33:58.401Z\", \"hypothesis\": \"MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). Third seed completing 3-seed set for statistical power.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/fewnerd_mf4v2_seed456/\\\"\", \"server\": \"autodl-5090-b\", \"gpu\": [\"cuda:2\"], \"pid\": \"334423\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_fewnerd_mf4_v2_s456.log\", \"submitted_at\": \"2026-05-21T08:33:57.773Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"exp_fewnerd_n16_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:47.609Z\", \"updated_at\": \"2026-05-21T08:33:10.578Z\", \"hypothesis\": \"FewNERD N=16 (seed=123): extending N-scaling curve to N=16 for Qwen3-8B-FT. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation. Second seed for 3-seed statistical power.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_n16_seed123/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_n16_seed123.log\"}, \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:3\", \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.7888, \"oracle_f1\": 0.9147, \"oracle_headroom\": 0.126, \"rho_fk_full\": 0.224, \"rho_sj_full\": 0.352, \"rho_fk_cond\": 0.083, \"rho_sj_cond\": 0.282, \"logprob_rho_full\": 0.28, \"logprob_rho_cond\": 0.258, \"instances\": 37648}, \"completed_at\": \"2026-05-21T08:33:10.578Z\"}, \"exp_fewnerd_n16_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:46.569Z\", \"updated_at\": \"2026-05-21T08:33:07.868Z\", \"hypothesis\": \"FewNERD N=16 (seed=42): extending N-scaling curve to N=16 for Qwen3-8B-FT. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_n16_seed42/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_n16_seed42.log\"}, \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:2\", \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.7886, \"oracle_f1\": 0.9059, \"oracle_headroom\": 0.117, \"rho_fk_full\": 0.162, \"rho_sj_full\": 0.211, \"rho_fk_cond\": -0.019, \"rho_sj_cond\": 0.212, \"logprob_rho_full\": 0.139, \"logprob_rho_cond\": 0.175, \"instances\": 37648}, \"completed_at\": \"2026-05-21T08:33:07.868Z\"}, \"exp_fewnerd_t12_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:11:46.378Z\", \"updated_at\": \"2026-05-21T08:32:53.474Z\", \"hypothesis\": \"FewNERD temperature ablation (T=1.2, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.2 --seed 456 --collect_logprobs --output_dir output/fewnerd_t12_s456/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 456, \"gpu\": \"cuda:1\", \"pid\": 305834, \"tmux_session\": \"fewnerd_t12_s456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t12_s456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t12_s456/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.7885, \"oracle_f1\": 0.8775, \"oracle_headroom\": 0.089, \"rho_fk_full\": 0.191, \"rho_sj_full\": 0.29, \"rho_fk_cond\": 0.015, \"rho_sj_cond\": 0.254, \"degeneracy_rate\": null, \"logprob_rho_full\": 0.196, \"logprob_rho_cond\": 0.245, \"instances\": 37648}, \"completed_at\": \"2026-05-21T08:32:53.474Z\"}, \"exp_fewnerd_mf4v2_s42\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T07:56:02.381Z\", \"updated_at\": \"2026-05-21T07:57:02.003Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/fewnerd_mf4v2_seed42/\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"13177\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_fewnerd_mf4v2_s42.log\", \"submitted_at\": \"2026-05-21T07:57:01.337Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"exp_fewnerd_mf4v2_s123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T07:55:59.499Z\", \"updated_at\": \"2026-05-21T07:56:59.570Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/fewnerd_mf4v2_seed123/\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"13035\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_fewnerd_mf4v2_s123.log\", \"submitted_at\": \"2026-05-21T07:56:58.909Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"exp_14b_inference_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-20T14:36:27.954Z\", \"updated_at\": \"2026-05-21T07:51:33.030Z\", \"hypothesis\": \"14B Qwen2.5 inference on FewNERD (N∈{1,2,4,8}): primary dataset should show oracle scaling law F1(N)=a-b*N^(-c) consistent at 14B scale, filling the scaling curve between 7B and 32B. N=16 cut per Director decision.\", \"notes\": \"2026-05-21T00:50 RESTORED to RUNNING per Director. PID 252310 confirmed alive by Reviewer (cuda:0 98% util, elapsed 16min). 5th false-negative misdiagnosis. N=1 greedy_f1=0.7985, N=2 greedy_f1=0.7985/oracle=0.8086, N=4 greedy_f1=0.7984/oracle=0.8544. kill_after_n8.sh active (PID 224789).\", \"spec\": {\"server\": \"autodl-5090-c\", \"pid\": 252310, \"gpu\": \"cuda:0\", \"model_name\": \"Qwen2.5-14B-Instruct\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:0\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T00:46:56.565632+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T07:17:12.232308+00:00\"}]}, \"conclusion\": \"success\", \"reproduce\": {\"finished_at\": \"2026-05-21T07:17:01.438Z\"}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-21T07:17:05.380Z\", \"metrics\": {\"fewnerd_n1\": {\"greedy_f1\": 0.7985, \"oracle_f1\": 0.7541, \"oracle_headroom\": -0.044, \"verdict\": \"FAIL\"}, \"fewnerd_n2\": {\"greedy_f1\": 0.7985, \"oracle_f1\": 0.8086, \"oracle_headroom\": 0.01, \"soft_jaccard_rho_full\": 0.205, \"rho_advantage\": -0.006, \"structural_beats_surface\": false, \"verdict\": \"FAIL\"}, \"fewnerd_n4\": {\"greedy_f1\": 0.7984, \"oracle_f1\": 0.8544, \"oracle_headroom\": 0.056, \"soft_jaccard_rho_full\": 0.314, \"rho_advantage\": 0.042, \"structural_beats_surface\": true, \"verdict\": \"MARGINAL\"}, \"fewnerd_n8\": {\"greedy_f1\": 0.7984, \"oracle_f1\": 0.8791, \"oracle_headroom\": 0.081, \"soft_jaccard_rho_full\": 0.324, \"rho_advantage\": 0.083, \"structural_beats_surface\": true, \"verdict\": \"MARGINAL\"}, \"cross_domain_scierc_conll\": \"completed but expected poor (cross-domain)\", \"n16_status\": \"cut per Director decision, kill_after_n8.sh executed\"}, \"checkpoint_path\": \"output/14b_final_inference/\"}, \"exp_fewnerd_mf4_v2_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:33:24.304Z\", \"updated_at\": \"2026-05-21T07:44:50.506Z\", \"hypothesis\": \"MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=42 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1. 3-seed statistical power.\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/fewnerd_mf4v2_seed42/\", \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0\", \"pid\": 320158, \"log_path\": \"~/runs/struct_self_consist_ie/exp_fewnerd_mf4_v2_s42.log\", \"submitted_at\": \"2026-05-21T05:33:33.770Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 42, \"checkpoint_path\": \"output/fewnerd_mf4v2_seed42/\", \"wall_clock_seconds\": 7644}, \"reproduce\": {\"finished_at\": \"2026-05-21T07:40:57.810Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-21T07:41:07.901551+00:00\"}]}, \"metrics\": {\"greedy_f1\": 0.7883, \"oracle_f1\": 0.8783, \"oracle_headroom\": 0.09, \"fleiss_kappa_mean\": 0.3531, \"soft_jaccard_mean\": 0.6747, \"rho_SJ_full\": 0.1634, \"rho_kappa_full\": 0.0476, \"rho_SJ_cond\": 0.1987, \"rho_kappa_cond\": -0.0327, \"rho_advantage_full\": 0.1158, \"rho_advantage_cond\": 0.2314, \"structural_beats_surface\": true, \"sample_f1_mean\": 0.6123, \"sample_f1_std\": 0.3913, \"sample_f1_pct_zero\": 23.09, \"n_instances\": 37648, \"n_valid_full\": 32565, \"n_valid_cond\": 28682, \"n_gold_empty_filtered\": 5083, \"n_greedy_f1_zero_filtered\": 3883, \"logprob_rho_full\": 0.1544, \"logprob_tau_full\": 0.115, \"logprob_auroc_full\": 0.5771, \"logprob_rho_cond\": 0.1641, \"logprob_tau_cond\": 0.123, \"logprob_auroc_cond\": 0.5768, \"verdict\": \"FAIL\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-21T07:44:50.506Z\"}, \"exp_fewnerd_mf4_v2_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:33:25.463Z\", \"updated_at\": \"2026-05-21T07:41:29.072Z\", \"hypothesis\": \"MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1. 3-seed statistical power.\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/fewnerd_mf4v2_seed123/\", \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:1\", \"pid\": 320302, \"log_path\": \"~/runs/struct_self_consist_ie/exp_fewnerd_mf4_v2_s123.log\", \"submitted_at\": \"2026-05-21T05:33:36.193Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 123, \"checkpoint_path\": \"output/fewnerd_mf4v2_seed123/\", \"wall_clock_seconds\": 7672.9, \"gpu_hours\": 2.13}, \"reproduce\": {\"finished_at\": \"2026-05-21T07:38:22.503Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-21T07:38:30.204681+00:00\"}]}, \"metrics\": {\"greedy_f1\": 0.7883, \"oracle_f1\": 0.8891, \"oracle_headroom\": 0.1009, \"fleiss_kappa_mean\": 0.3483, \"soft_jaccard_mean\": 0.6689, \"rho_SJ_full\": 0.307, \"rho_kappa_full\": 0.1588, \"rho_SJ_cond\": 0.1966, \"rho_kappa_cond\": 0.0031, \"rho_advantage_full\": 0.1482, \"rho_advantage_cond\": 0.1935, \"structural_beats_surface\": true, \"sample_f1_mean\": 0.6364, \"sample_f1_std\": 0.3819, \"sample_f1_pct_zero\": 20.49, \"n_instances\": 37648, \"n_valid_full\": 32565, \"n_valid_cond\": 28685, \"n_gold_empty_filtered\": 5083, \"n_greedy_f1_zero_filtered\": 3880, \"logprob_rho_full\": 0.2193, \"logprob_tau_full\": 0.1641, \"logprob_auroc_full\": 0.6056, \"logprob_rho_cond\": 0.1818, \"logprob_tau_cond\": 0.1369, \"logprob_auroc_cond\": 0.5892, \"verdict\": \"MARGINAL\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T07:41:29.072Z\"}, \"exp_fewnerd_n16_s456_v2\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T07:18:11.587Z\", \"updated_at\": \"2026-05-21T07:19:10.627Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/fewnerd_n16_seed456_v2/\\\"\", \"server\": \"autodl-5090-c\", \"gpu\": [\"cuda:0\"], \"pid\": \"293438\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_fewnerd_n16_s456_v2.log\", \"submitted_at\": \"2026-05-21T07:18:10.938Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/fewnerd/\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances, N=16)\"}, \"hypothesis\": \"FewNERD N=16 (seed=456, v2 rerun): data lost in previous run. Extending N-scaling curve to N=16 for Qwen3-8B-FT, critical for F1(N)=a-b*N^(-c) scaling law. Third seed for 3-seed statistical power.\"}, \"exp_fewnerd_7b_n16_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:32:29.897Z\", \"updated_at\": \"2026-05-21T07:17:35.321Z\", \"hypothesis\": \"FewNERD N=16 with Qwen2.5-7B: extending N-scaling curve to N=16 for 7B model. At N=8 the 7B model shows diminishing oracle gains; N=16 tests whether the plateau continues or breaks, providing a critical data point for the N-scaling law F1(N)=a-b*N^(-c) at the 7B scale.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen25-7b-fewnerd-merged --data_dir data/fewnerd/ --dataset fewnerd --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/fewnerd_7b_n16_seed42/\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen25-7b-fewnerd-merged\", \"seed\": 42, \"gpu\": \"cuda:2\", \"pid\": 264869, \"log_path\": \"N/A\", \"checkpoint_path\": \"N/A\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-fewnerd-merged\", \"eval_data\": \"fewnerd test set (37648 instances, N=16)\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T07:17:35.321Z\"}, \"exp_fewnerd_n16_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:45.512Z\", \"updated_at\": \"2026-05-21T07:13:32.225Z\", \"hypothesis\": \"FewNERD N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation. Third seed for 3-seed statistical power.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/fewnerd_n16_seed456/\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/fewnerd/\", \"data_count\": 14770, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 456}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T07:13:32.225Z\"}, \"exp_e2_pretrained_fewnerd\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:52:06.559Z\", \"updated_at\": \"2026-05-21T07:00:36.991Z\", \"hypothesis\": \"E2 pre-trained baseline: Qwen2.5-7B-Instruct (unfinetuned) on FewNERD SC pipeline N=8 T=1.0. Tests whether correlation-selection gap exists without task-specific fine-tuning. If gap persists → phenomenon is model-intrinsic, not fine-tuning artifact.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path /root/autodl-tmp/models/Qwen2.5-7B-Instruct/Qwen/Qwen2___5-7B-Instruct --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/e2_pretrained_fewnerd/\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"8406\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_e2_pretrained_fewnerd.log\", \"submitted_at\": \"2026-05-21T06:59:29.791Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/fewnerd/\", \"data_count\": 37648, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"pretrained_base\", \"eval_data\": \"fewnerd\"}}, \"exp_conll_mf4_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:09:11.484Z\", \"updated_at\": \"2026-05-21T06:54:56.063Z\", \"hypothesis\": \"MF4 pipeline fix: CoNLL N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). Extends exp_conll_t10_s42 to 3-seed set for statistical power.\", \"parent\": \"exp_conll_t10_s42\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/conll_mf4_seed456/\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"data/conll2003/test.json\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-21T06:54:56.063Z\"}, \"exp_frontier_sc_gemini25pro\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-21T06:50:24.793Z\", \"updated_at\": \"2026-05-21T06:52:09.740Z\", \"hypothesis\": \"Frontier model Gemini 2.5 Pro on FewNERD SC (200 inst, N=8, T=1.0): 4-family cross-validation. If correlation-selection gap persists across GPT + Claude + Gemini + DeepSeek, the finding is universal.\", \"spec\": {\"command\": \"python -u code/run_frontier_sc.py --model google/gemini-2.5-pro --base_url http://47.94.22.126/v1 --dataset fewnerd --n_instances 200 --n_samples 8 --temperature 1.0 --output_dir output/frontier_sc_gemini25pro/ --max_workers 4\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 200, \"model_name\": \"google/gemini-2.5-pro\", \"seed\": 42}}, \"exp_conll_mf4_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:09:06.021Z\", \"updated_at\": \"2026-05-21T05:53:05.635Z\", \"hypothesis\": \"MF4 pipeline fix: CoNLL N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). Extends exp_conll_t10_s42 to 3-seed set for statistical power.\", \"parent\": \"exp_conll_t10_s42\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/conll_mf4_seed123/\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"data/conll2003/test.json\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-21T05:53:05.635Z\"}, \"exp_fewnerd_t05_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:11:43.659Z\", \"updated_at\": \"2026-05-21T05:50:43.777Z\", \"hypothesis\": \"FewNERD temperature ablation (T=0.5, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.5 --seed 456 --collect_logprobs --output_dir output/fewnerd_t05_s456/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 456, \"gpu\": \"cuda:0\", \"pid\": 305832, \"tmux_session\": \"fewnerd_t05_s456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t05_s456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t05_s456/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"reproduce\": {\"finished_at\": \"2026-05-21T05:32:07.140Z\"}, \"failure_reason\": \"false alarm: cron detected process dead but experiment had completed successfully (37648/37648 instances, report.json + samples.jsonl generated)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T05:32:10.869Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T05:32:18.820026+00:00\"}]}}, \"exp_fewnerd_mf4_s456\": {\"status\": \"QUEUED\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:09:02.532Z\", \"updated_at\": \"2026-05-21T05:30:51.650Z\", \"hypothesis\": \"MF4 pipeline fix: FewNERD N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1 metric. Required for 3-seed statistical power with unified pipeline.\", \"conclusion\": \"killed\"}, \"exp_fewnerd_mf4_s123\": {\"status\": \"QUEUED\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:08:59.588Z\", \"updated_at\": \"2026-05-21T05:30:50.417Z\", \"hypothesis\": \"MF4 pipeline fix: FewNERD N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1 metric. Required for 3-seed statistical power with unified pipeline.\", \"conclusion\": \"killed\"}, \"exp_fewnerd_mf4_s42\": {\"status\": \"QUEUED\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:08:56.774Z\", \"updated_at\": \"2026-05-21T05:30:49.304Z\", \"hypothesis\": \"MF4 pipeline fix: FewNERD N=8 T=1.0 seed=42 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1 metric. Required for 3-seed statistical power with unified pipeline.\", \"conclusion\": \"killed\"}, \"exp_14b_inference_conll\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T14:36:26.315Z\", \"updated_at\": \"2026-05-21T04:57:40.651Z\", \"hypothesis\": \"14B Qwen2.5 inference on CoNLL (N∈{1,2,4,8}): filling scale curve between 8B (greedy F1=0.907) and 32B. Tests whether 14B shows intermediate behavior in SC diagnostic metrics.\", \"reproduce\": {\"finished_at\": \"2026-05-20T14:49:00.238Z\"}, \"failure_reason\": \"Director ordered kill: cross-domain 14B inference deemed valueless by Reviewer. Only FewNERD 14B inference retained.\", \"conclusion\": \"killed\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T14:49:09.529266+00:00\"}]}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"spec\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"pid\": 278145, \"model_name\": \"Qwen2.5-14B-Instruct (base)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003/\", \"data_count\": 3453, \"seed\": 42, \"command\": \"python -u code/run_mvp_pilot.py --model_path Qwen/Qwen2.5-14B-Instruct --data_dir data/conll2003/ --dataset conll2003 --n_samples 8 --temperature 1.0 --seed 42 --enforce_eager --output_dir output/14b_base_inference/conll2003_n1/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/14b_conll_inference.log\"}, \"completed_at\": \"2026-05-21T04:57:40.651Z\"}, \"exp_conll_n16_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:49.693Z\", \"updated_at\": \"2026-05-21T04:53:40.278Z\", \"hypothesis\": \"CoNLL N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation. Third seed for 3-seed statistical power.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie/ && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/conll_n16_s456/\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"996070\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s456.log\", \"submitted_at\": \"2026-05-21T04:51:06.525Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 40.2, \"gpu_hours\": 0.01}, \"pid\": \"996070\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s456.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie/ && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/conll_n16_s456/\\\"\", \"finished_at\": \"2026-05-21T04:51:43.069Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T04:51:46.724Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T04:51:52.994852+00:00\"}]}, \"notes\": \"失败原因: tokenizer vocab_file=None — checkpoints/qwen3-8b-conll2003-merged 缺少 vocab.json，vLLM 初始化 tokenizer 时 TypeError。与 exp_conll_n16_s123 同根因。| 已有成果: 无（启动即崩溃）| 建议: 修复 merged checkpoint tokenizer 文件后重跑\"}, \"exp_conll_n16_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:48.660Z\", \"updated_at\": \"2026-05-21T04:53:39.049Z\", \"hypothesis\": \"CoNLL N=16 (seed=123): extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation. Second seed (s42 running).\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie/ && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/conll_n16_s123/\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"995788\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s123.log\", \"submitted_at\": \"2026-05-21T04:50:56.582Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 36.3, \"gpu_hours\": 0.01}, \"pid\": \"995788\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s123.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie/ && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/conll_n16_s123/\\\"\", \"finished_at\": \"2026-05-21T04:51:29.216Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T04:51:32.929Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T04:51:39.166251+00:00\"}]}, \"notes\": \"失败原因: tokenizer vocab_file=None — checkpoints/qwen3-8b-conll2003-merged 缺少 vocab.json，vLLM 初始化 tokenizer 时 TypeError。与 exp_conll_n16_s456 同根因。| 已有成果: 无（启动即崩溃）| 建议: 修复 merged checkpoint tokenizer 文件后重跑\"}, \"exp_scierc_n16_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:43.414Z\", \"updated_at\": \"2026-05-21T04:44:33.829Z\", \"hypothesis\": \"SciERC N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT on SciERC. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation. Third seed for 3-seed statistical power.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/scierc_n16_seed456/\", \"server\": \"autodl-5090-b\", \"data_path\": \"data/scierc/processed_data/\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456}, \"log_path\": \"logs/scierc_n16_seed456.log\", \"checkpoint_path\": \"output/scierc_n16_seed456/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:44:33.829Z\"}, \"exp_scierc_n16_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:42.345Z\", \"updated_at\": \"2026-05-21T04:44:30.424Z\", \"hypothesis\": \"SciERC N=16 (seed=123): extending N-scaling curve to N=16 for Qwen3-8B-FT on SciERC. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation. Second seed (s42 completed in exp-001).\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/scierc_n16_seed123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"data/scierc/processed_data/\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123}, \"log_path\": \"logs/scierc_n16_seed123.log\", \"checkpoint_path\": \"output/scierc_n16_seed123/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:44:30.424Z\"}, \"exp_scierc_t12_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:24:04.240Z\", \"updated_at\": \"2026-05-21T04:25:04.160Z\", \"hypothesis\": \"SciERC temperature ablation (T=1.2, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.\", \"parent\": \"exp_scierc_t12_s123\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t12_s456/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t12_s456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:22.602Z\", \"metrics\": {\"greedy_f1\": 0.663, \"oracle_f1\": 0.782, \"rho_SJ_full\": 0.42, \"rho_FK_full\": 0.32, \"rho_advantage\": 0.099, \"oracle_headroom\": 0.119, \"degeneracy_pct\": 14.1, \"verdict\": \"PASS\"}}, \"exp_conll_n16_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:11:59.589Z\", \"updated_at\": \"2026-05-21T04:25:02.949Z\", \"hypothesis\": \"CoNLL N=16 ablation (T=1.0, seed=42): test whether doubling sample count from N=8 to N=16 improves SC diagnostic correlation and oracle F1 on CoNLL-2003. Qwen3-8B-FT.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/conll_n16_s42/\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003/test.json\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42, \"gpu\": \"cuda:3\", \"pid\": 269975, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/conll_n16_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_s42/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set (3453 instances, N=16)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:19.862Z\", \"metrics\": {\"greedy_f1\": 0.908, \"oracle_f1\": 0.959, \"rho_SJ_full\": 0.446, \"rho_FK_full\": 0.427, \"rho_advantage\": 0.019, \"oracle_headroom\": 0.051, \"degeneracy_pct\": 7.8, \"verdict\": \"PASS\"}}, \"exp_scierc_t08_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:11:56.854Z\", \"updated_at\": \"2026-05-21T04:25:01.025Z\", \"hypothesis\": \"SciERC temperature ablation (T=0.8, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 8 --temperature 0.8 --seed 123 --collect_logprobs --output_dir output/scierc_t08_s123/\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data/test.json\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": \"cuda:1\", \"pid\": 269240, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t08_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t08_s123/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"scierc test set (551 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:17.181Z\", \"metrics\": {\"greedy_f1\": 0.662, \"oracle_f1\": 0.773, \"rho_SJ_full\": 0.382, \"rho_FK_full\": 0.298, \"rho_advantage\": 0.084, \"oracle_headroom\": 0.11, \"degeneracy_pct\": 11.2, \"verdict\": \"MARGINAL\"}}, \"exp_scierc_t08_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:24:03.202Z\", \"updated_at\": \"2026-05-21T04:24:59.796Z\", \"hypothesis\": \"SciERC temperature ablation (T=0.8, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.\", \"parent\": \"exp_scierc_t08_s123\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t08_s456/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t08_s456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:14.128Z\", \"metrics\": {\"greedy_f1\": 0.664, \"oracle_f1\": 0.769, \"rho_SJ_full\": 0.362, \"rho_FK_full\": 0.244, \"rho_advantage\": 0.118, \"oracle_headroom\": 0.105, \"degeneracy_pct\": 11.9, \"verdict\": \"MARGINAL\"}}, \"exp_scierc_t05_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:24:01.834Z\", \"updated_at\": \"2026-05-21T04:24:58.182Z\", \"hypothesis\": \"SciERC temperature ablation (T=0.5, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.\", \"parent\": \"exp_scierc_t05_s123\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t05_s456/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t05_s456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:11.475Z\", \"metrics\": {\"greedy_f1\": 0.663, \"oracle_f1\": 0.746, \"rho_SJ_full\": 0.326, \"rho_FK_full\": 0.272, \"rho_advantage\": 0.054, \"oracle_headroom\": 0.083, \"degeneracy_pct\": 10.3, \"verdict\": \"MARGINAL\"}}, \"exp_scierc_t12_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:11:53.869Z\", \"updated_at\": \"2026-05-21T04:24:56.285Z\", \"hypothesis\": \"SciERC temperature ablation (T=1.2, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 8 --temperature 1.2 --seed 123 --collect_logprobs --output_dir output/scierc_t12_s123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data/test.json\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": \"cuda:3\", \"pid\": 305838, \"tmux_session\": \"scierc_t12_s123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t12_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t12_s123/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"scierc test set (551 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:08.764Z\", \"metrics\": {\"greedy_f1\": 0.664, \"oracle_f1\": 0.788, \"rho_SJ_full\": 0.346, \"rho_FK_full\": 0.223, \"rho_advantage\": 0.124, \"oracle_headroom\": 0.124, \"degeneracy_pct\": 13.9, \"verdict\": \"MARGINAL\"}}, \"exp_scierc_t05_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:11:49.272Z\", \"updated_at\": \"2026-05-21T04:24:54.884Z\", \"hypothesis\": \"SciERC temperature ablation (T=0.5, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 8 --temperature 0.5 --seed 123 --collect_logprobs --output_dir output/scierc_t05_s123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data/test.json\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": \"cuda:2\", \"pid\": 305836, \"tmux_session\": \"scierc_t05_s123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t05_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t05_s123/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"scierc test set (551 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:06.127Z\", \"metrics\": {\"greedy_f1\": 0.665, \"oracle_f1\": 0.743, \"rho_SJ_full\": 0.322, \"rho_FK_full\": 0.295, \"rho_advantage\": 0.026, \"oracle_headroom\": 0.078, \"degeneracy_pct\": 10, \"verdict\": \"MARGINAL\"}}, \"exp_fewnerd_t08_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:47:48.690Z\", \"updated_at\": \"2026-05-21T04:24:53.510Z\", \"hypothesis\": \"FewNERD T-ablation seed=456 (T=0.8): third seed for T=0.8 sweet-spot, providing 3-seed statistical power for the key operating point. With seeds 42/123/456, can compute confidence intervals on rho_SJ and degeneracy_rate for the recommended T=0.8 setting.\", \"parent\": \"exp_fewnerd_t08_s42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.8 --seed 456 --collect_logprobs --output_dir output/fewnerd_t08_s456/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 456, \"gpu\": \"cuda:3\", \"tmux_session\": \"fewnerd_t08_s456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t08_s456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t08_s456/\", \"pid\": 297409, \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:03.444Z\", \"metrics\": {\"greedy_f1\": 0.788, \"oracle_f1\": 0.877, \"rho_SJ_full\": 0.328, \"rho_FK_full\": 0.202, \"rho_advantage\": 0.126, \"oracle_headroom\": 0.088, \"degeneracy_pct\": 16.3, \"verdict\": \"MARGINAL\"}}, \"exp_fewnerd_t12_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:47:46.558Z\", \"updated_at\": \"2026-05-21T04:24:52.149Z\", \"hypothesis\": \"FewNERD T-ablation seed=123 replication (T=1.2): second seed for statistical power on T=1.2 negative result (over-diversification, 28.2% degeneracy, lowest rho_SJ=0.136 in seed=42). Confirms T=1.2 is consistently suboptimal for SC diagnostics on FewNERD.\", \"parent\": \"exp_fewnerd_t12_s42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.2 --seed 123 --collect_logprobs --output_dir output/fewnerd_t12_s123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 123, \"gpu\": \"cuda:2\", \"tmux_session\": \"fewnerd_t12_s123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t12_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t12_s123/\", \"pid\": 297143, \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-21T04:24:00.722Z\", \"metrics\": {\"greedy_f1\": 0.789, \"oracle_f1\": 0.887, \"rho_SJ_full\": 0.285, \"rho_FK_full\": 0.163, \"rho_advantage\": 0.122, \"oracle_headroom\": 0.098, \"degeneracy_pct\": 24.7, \"verdict\": \"FAIL\"}}, \"exp_fewnerd_t08_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:47:44.136Z\", \"updated_at\": \"2026-05-21T04:24:50.244Z\", \"hypothesis\": \"FewNERD T-ablation seed=123 replication (T=0.8): second seed for statistical power on T=0.8 sweet-spot hypothesis (best rho_advantage=0.102 SJ over Fleiss, balanced oracle headroom=8.66% in seed=42). Tests robustness of T=0.8 as optimal operating point for SC diagnostic.\", \"parent\": \"exp_fewnerd_t08_s42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.8 --seed 123 --collect_logprobs --output_dir output/fewnerd_t08_s123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 123, \"gpu\": \"cuda:1\", \"tmux_session\": \"fewnerd_t08_s123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t08_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t08_s123/\", \"pid\": 296880, \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:23:57.853Z\", \"metrics\": {\"greedy_f1\": 0.789, \"oracle_f1\": 0.884, \"rho_SJ_full\": 0.336, \"rho_FK_full\": 0.221, \"rho_advantage\": 0.116, \"oracle_headroom\": 0.095, \"degeneracy_pct\": 16.7, \"verdict\": \"MARGINAL\"}}, \"exp_fewnerd_t05_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:47:41.794Z\", \"updated_at\": \"2026-05-21T04:24:48.794Z\", \"hypothesis\": \"FewNERD T-ablation seed=123 replication (T=0.5): second seed for statistical power on T=0.5 findings (highest rho_SJ=0.267, lowest oracle headroom=6.85% in seed=42). Confirms whether the diagnostic correlation ranking T=0.5>T=0.8>T=1.2 is stable across seeds or driven by seed-specific variance.\", \"parent\": \"exp_fewnerd_t05_s42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.5 --seed 123 --collect_logprobs --output_dir output/fewnerd_t05_s123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 123, \"gpu\": \"cuda:0\", \"tmux_session\": \"fewnerd_t05_s123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t05_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t05_s123/\", \"pid\": 296744, \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:23:54.964Z\", \"metrics\": {\"greedy_f1\": 0.789, \"oracle_f1\": 0.864, \"rho_SJ_full\": 0.35, \"rho_FK_full\": 0.295, \"rho_advantage\": 0.055, \"oracle_headroom\": 0.075, \"degeneracy_pct\": 13.5, \"verdict\": \"MARGINAL\"}}, \"exp_32b_inference_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:21:12.060Z\", \"updated_at\": \"2026-05-21T04:24:47.338Z\", \"hypothesis\": \"32B fine-tuned model (Qwen2.5-32B-Instruct QLoRA, best checkpoint-32000) FewNERD inference with N=8 SC sampling. Scaling from 8B→32B should improve per-sample quality and strengthen SC diagnostic correlation (Fleiss kappa / Soft-Jaccard vs F1). Comparison baseline: Qwen3-8B-FT FewNERD results.\", \"parent\": \"exp_qwen25_32b_fewnerd\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_32b_fewnerd_n8_s42/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/inference_32b_fewnerd_n8_s42.log\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen25-32b-fewnerd-merged --data_dir data/fewnerd --dataset fewnerd --n_samples 8 --temperature 1.0 --seed 42 --output_dir output/exp_32b_fewnerd_n8_s42 --tensor_parallel 4 --collect_logprobs\", \"server\": \"autodl-5090\", \"model_name\": \"qwen25-32b-fewnerd-merged\", \"seed\": 42, \"data_path\": \"data/fewnerd\", \"data_count\": 301184}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:23:52.252Z\", \"metrics\": {\"greedy_f1\": 0.8, \"oracle_f1\": 0.879, \"rho_SJ_full\": 0.32, \"rho_FK_full\": 0.242, \"rho_advantage\": 0.078, \"fleiss_kappa_mean\": 0.533, \"soft_jaccard_mean\": 0.802, \"oracle_headroom\": 0.079, \"verdict\": \"MARGINAL\"}}, \"exp_hidden_state_probe_fulldata\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:13:17.554Z\", \"updated_at\": \"2026-05-21T04:13:53.843Z\", \"hypothesis\": \"Hidden states of fine-tuned Qwen3-8B encode entity quality information that a linear probe can detect with AUROC significantly above chance, even under GroupKFold (no instance leakage). CoNLL probe should exceed MV baseline (0.87).\", \"spec\": {\"command\": \"extract_fulldata_hidden_states.py + groupkfold_probe_fulldata.py\", \"server\": \"autodl-5090-b (fewnerd), autodl-5090-c (conll, scierc)\", \"data_path\": \"output/entity_probe_fulldata/\", \"data_count\": \"CoNLL 850inst/14777ent, FewNERD 1698inst/41096ent, SciERC 539inst/13188ent\", \"model_name\": \"Qwen3-8B fine-tuned\", \"seed\": \"42,123,456\"}, \"log_path\": \"artifacts/exp_hidden_state_probe_fulldata/data/groupkfold_probe_fulldata_results.json\", \"checkpoint_path\": \"output/entity_probe_fulldata/ on autodl-5090-b and autodl-5090-c\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:13:53.843Z\"}, \"exp_hidden_state_probe\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:07:00.977Z\", \"updated_at\": \"2026-05-21T03:21:54.284Z\", \"hypothesis\": \"Entity quality information (in_gold vs not) is encoded in the fine-tuned model's last-layer hidden states at entity token positions. If probe AUROC ≈ MV AUROC (0.87), the signal exists in representation but ESJ prompt-based reading (AUROC=0.51) fails to access it — a prompt interface failure. If probe AUROC ≈ 0.51, the information is genuinely absent from single-sample representations.\", \"spec\": {\"command\": \"python code/hidden_state_probe.py --dataset {fewnerd,conll} --max_instances 500\", \"server\": \"autodl-5090-c\", \"data_path\": \"output/{exp_tlow_fewnerd_t05_s42,exp_conll_t08_seed42}/samples.jsonl\", \"data_count\": 1000, \"model_name\": \"Qwen3-8B-FT (per-dataset checkpoints)\", \"seed\": 42, \"gpu\": \"cuda:2 (fewnerd), cuda:3 (conll)\", \"pid\": 261583, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/probe_extract_{fewnerd,conll}.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/entity_probe_auroc/\"}, \"metrics\": {\"entity_level_stratifiedkfold_auroc\": {\"conll\": 0.9796, \"fewnerd\": 0.9872, \"scierc\": 0.9766}, \"groupkfold_auroc_corrected\": {\"conll\": 0.8849, \"fewnerd\": 0.6513, \"scierc\": 0.6344}, \"groupkfold_delta\": {\"conll\": -0.0947, \"fewnerd\": -0.3359, \"scierc\": -0.3422}, \"groupkfold_probe_above_mv\": {\"conll\": true, \"fewnerd\": false, \"scierc\": false}, \"baselines\": {\"mv_agreement_auroc\": 0.87, \"esj_prompt_auroc\": 0.51}, \"note\": \"GroupKFold fixes instance-level leakage. Only conll retains probe > MV after correction.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T02:11:40.936Z\", \"notes\": \"Probe AUROC far exceeds both baselines: FewNERD 0.987, CoNLL 0.980 vs MV 0.87 vs ESJ 0.51. The model's last-layer hidden states at entity token positions encode correctness information at very high fidelity — even higher than what multi-sample voting captures. This is strong evidence for a prompt interface failure: the model knows which entities are correct but cannot express this through prompting (ESJ). LogisticRegression with 5-fold CV × 3 seeds. SciERC extraction not run (no matching 8B samples data available).\"}, \"exp_conll_t10_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:32:32.990Z\", \"updated_at\": \"2026-05-21T02:44:20.817Z\", \"hypothesis\": \"CoNLL T=1.0 baseline (seed=42): fills the gap in the temperature ablation matrix (T=0.5/0.8/1.2 already complete with 3 seeds). T=1.0 is the default sampling temperature and should show intermediate behavior between T=0.8 (sweet spot) and T=1.2 (over-diversification), completing the temperature sweep for CoNLL.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/exp_conll_t10_seed42/\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003/test.json\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42, \"gpu\": \"cuda:3\", \"pid\": 265554, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/conll_t10_seed42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t10_seed42/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set (3453 instances)\"}, \"metrics\": {\"greedy_f1\": 0.9077, \"oracle_f1\": 0.9503, \"oracle_headroom\": 0.0426, \"rho_SJ_full\": 0.4249, \"rho_kappa_full\": 0.4037, \"rho_SJ_cond\": 0.4154, \"rho_kappa_cond\": 0.3793, \"rho_advantage\": 0.0212, \"fleiss_kappa_mean\": 0.772, \"soft_jaccard_mean\": 0.895, \"sample_f1_mean\": 0.871, \"sample_f1_pct_zero\": 7.53, \"verdict\": \"PASS\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T02:44:20.817Z\"}, \"exp_scierc_probe\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:32:25.557Z\", \"updated_at\": \"2026-05-21T02:41:37.846Z\", \"hypothesis\": \"SciERC hidden state probe: test if linear classifier on last-layer hidden states can predict entity quality (match vs non-match against gold). If AUROC ≈ 0.98 (consistent with FewNERD=0.987, CoNLL=0.980), confirms entity quality info is universally encoded in representations across datasets, and prompt-based self-judgment (ESJ AUROC=0.51) fails to access this information.\", \"spec\": {\"command\": \"Step 1: CUDA_VISIBLE_DEVICES=1 python -u code/run_mvp_pilot.py --dataset scierc --n_samples 8 --temperature 0.8; Step 2: python code/hidden_state_probe.py --dataset scierc --gpu 1\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data/test.json\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"gpu\": \"cuda:1\", \"pid\": 264061, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_8b_inference.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/entity_probe_auroc/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"scierc test set (551 instances)\"}, \"metrics\": {\"scierc_auroc_mean\": 0.9766, \"scierc_auroc_std\": 0.0011, \"scierc_auroc_seeds\": [0.9771, 0.9751, 0.9775], \"n_entities\": 12933, \"positive_rate\": 0.654, \"interpretation\": \"HIGH — info in representation, prompt interface fails\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T02:41:37.846Z\"}, \"exp_multi_model_correlation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:04:21.487Z\", \"updated_at\": \"2026-05-21T02:05:04.778Z\", \"hypothesis\": \"Cross-family models (Qwen vs LLaMA) have lower per-instance error correlation than same-family models, explaining why cross-model ensemble improves F1 by +0.42pp\", \"spec\": {\"command\": \"python3 code/multi_model_error_correlation.py --output_dir output/multi_model_correlation/\", \"server\": \"autodl-5090\", \"data_path\": \"output/*/samples.jsonl\", \"data_count\": 9004, \"model_name\": \"Qwen3-8B-FT + LLaMA-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/multi_model_correlation/error_correlation_report.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T02:05:04.778Z\"}, \"exp_conll_t12_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:43:52.368Z\", \"updated_at\": \"2026-05-21T01:59:40.017Z\", \"hypothesis\": \"CoNLL temperature ablation (T=1.2, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"parent\": \"exp_conll_t12_s123\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 1.2 --seed 456 --output_dir output/exp_conll_t12_seed456\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"pid\": 255217, \"gpu\": \"cuda:3\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t12_seed456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t12_seed456/\", \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"data/conll2003\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.9071, \"oracle_f1\": 0.9452, \"oracle_headroom\": 0.0381, \"fleiss_kappa_mean\": 0.7005, \"soft_jaccard_mean\": 0.8513, \"rho_SJ_F1_full\": 0.4553, \"rho_SJ_F1_conditional\": 0.4259, \"degeneracy_rate_pct\": 8.34, \"rho_advantage\": 0.0265, \"verdict\": \"PASS\"}, \"completed_at\": \"2026-05-21T01:59:40.017Z\"}, \"exp_conll_t08_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:43:51.393Z\", \"updated_at\": \"2026-05-21T01:59:37.027Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.8, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"parent\": \"exp_conll_t08_s123\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 0.8 --seed 456 --output_dir output/exp_conll_t08_seed456\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"pid\": 254524, \"gpu\": \"cuda:2\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t08_seed456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t08_seed456/\", \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"data/conll2003\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.9064, \"oracle_f1\": 0.9407, \"oracle_headroom\": 0.0343, \"fleiss_kappa_mean\": 0.8229, \"soft_jaccard_mean\": 0.9233, \"rho_SJ_F1_full\": 0.4877, \"rho_SJ_F1_conditional\": 0.4756, \"degeneracy_rate_pct\": 6.29, \"rho_advantage\": 0.0058, \"verdict\": \"PASS\"}, \"completed_at\": \"2026-05-21T01:59:37.027Z\"}, \"exp_conll_t05_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:43:49.873Z\", \"updated_at\": \"2026-05-21T01:59:34.389Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.5, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"parent\": \"exp_conll_t05_s123\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 0.5 --seed 456 --output_dir output/exp_conll_t05_seed456\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"pid\": 253823, \"gpu\": \"cuda:1\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t05_seed456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t05_seed456/\", \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"data/conll2003\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.9075, \"oracle_f1\": 0.9338, \"oracle_headroom\": 0.0263, \"fleiss_kappa_mean\": 0.8885, \"soft_jaccard_mean\": 0.9551, \"rho_SJ_F1_full\": 0.4549, \"rho_SJ_F1_conditional\": 0.469, \"degeneracy_rate_pct\": 5.62, \"rho_advantage\": 0.0044, \"verdict\": \"PASS\"}, \"completed_at\": \"2026-05-21T01:59:34.389Z\"}, \"exp_fewnerd_t05_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:41:05.687Z\", \"updated_at\": \"2026-05-21T00:47:06.206Z\", \"hypothesis\": \"FewNERD temperature ablation (T=0.5): test how lower temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwen3-8B-FT, seed=42. Lower T should reduce sampling diversity, potentially increasing degeneracy while improving per-sample quality.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.5 --seed 42 --collect_logprobs --output_dir output/fewnerd_t05_s42/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 42, \"gpu\": \"cuda:0\", \"tmux_session\": \"fewnerd_t05\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t05_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t05_s42/\"}, \"metrics\": {\"greedy_f1\": 0.7884, \"oracle_f1\": 0.8569, \"oracle_headroom\": 0.0685, \"sample_f1_mean\": 0.7154, \"degeneracy_rate\": 0.146, \"fleiss_kappa_mean\": 0.6332, \"soft_jaccard_mean\": 0.8653, \"rho_SJ_F1_full\": 0.2667, \"rho_SJ_F1_conditional\": 0.2988, \"rho_fleiss_F1_full\": 0.2231, \"rho_fleiss_F1_conditional\": 0.2338, \"rho_logprob_F1_full\": 0.3558, \"rho_logprob_F1_conditional\": 0.3025, \"structural_beats_surface\": true, \"rho_advantage\": 0.0435}, \"conclusion\": \"success\", \"notes\": \"T=0.5 on FewNERD has highest absolute rho_SJ=0.267 (full), 0.299 (conditional) among T-ablation, but lowest oracle headroom (6.85%) meaning SC oracle gain is smallest. Lowest degeneracy (14.6%), highest sample quality (0.715). SJ advantage over Fleiss only 0.044 because Fleiss also high (0.223). Logprob baseline dominates at this T (rho=0.356). Tradeoff: low T maximizes diagnostic correlation but minimizes room for SC to help.\", \"completed_at\": \"2026-05-21T00:47:06.206Z\"}, \"exp_fewnerd_t08_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:41:07.634Z\", \"updated_at\": \"2026-05-21T00:45:13.333Z\", \"hypothesis\": \"FewNERD temperature ablation (T=0.8): test how moderate-low temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwen3-8B-FT, seed=42. T=0.8 is a sweet-spot candidate balancing diversity and quality.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.8 --seed 42 --collect_logprobs --output_dir output/fewnerd_t08_s42/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 42, \"gpu\": \"cuda:1\", \"tmux_session\": \"fewnerd_t08\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t08_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t08_s42/\"}, \"metrics\": {\"greedy_f1\": 0.7884, \"oracle_f1\": 0.875, \"oracle_headroom\": 0.0866, \"sample_f1_mean\": 0.6622, \"degeneracy_rate\": 0.1897, \"fleiss_kappa_mean\": 0.4439, \"soft_jaccard_mean\": 0.7572, \"rho_SJ_F1_full\": 0.2062, \"rho_SJ_F1_conditional\": 0.2248, \"rho_fleiss_F1_full\": 0.1038, \"rho_logprob_F1_full\": 0.2323, \"rho_logprob_F1_conditional\": 0.1984, \"structural_beats_surface\": true, \"rho_advantage\": 0.1024}, \"conclusion\": \"success\", \"notes\": \"T=0.8 confirms sweet-spot hypothesis on FewNERD: best rho_SJ_F1=0.206 (full), 0.225 (conditional), lowest degeneracy (19%), highest sample quality (mean F1=0.662). SJ beats Fleiss by 0.102 rho advantage. Logprob baseline rho=0.232 (full) surprisingly high — SJ diagnostic matches logprob informativeness at this T. Verdict FAIL only because MVP single-subtask threshold not met, but T=0.8 is clearly the best operating point.\", \"completed_at\": \"2026-05-21T00:45:13.333Z\"}, \"exp_fewnerd_t12_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:41:09.018Z\", \"updated_at\": \"2026-05-21T00:44:30.280Z\", \"hypothesis\": \"FewNERD temperature ablation (T=1.2): test how higher temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwen3-8B-FT, seed=42. Higher T should increase diversity and reduce degeneracy but degrade per-sample quality.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.2 --seed 42 --collect_logprobs --output_dir output/fewnerd_t12_s42/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 42, \"gpu\": \"cuda:2\", \"tmux_session\": \"fewnerd_t12\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t12_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t12_s42/\"}, \"metrics\": {\"greedy_f1\": 0.7888, \"oracle_f1\": 0.875, \"oracle_headroom\": 0.0862, \"sample_f1_mean\": 0.5524, \"degeneracy_rate\": 0.2818, \"fleiss_kappa_mean\": 0.283, \"soft_jaccard_mean\": 0.5894, \"rho_SJ_F1_full\": 0.136, \"rho_SJ_F1_conditional\": 0.2125, \"rho_fleiss_F1_full\": 0.0605, \"rho_logprob_F1_conditional\": 0.1912, \"structural_beats_surface\": true, \"rho_advantage\": 0.0755}, \"conclusion\": \"negative\", \"notes\": \"T=1.2 on FewNERD: high oracle headroom (8.6%) but poor SC diagnostic correlation (rho_SJ=0.136 full, 0.213 conditional). High degeneracy (28.2% zero-F1 samples) and low per-sample quality (mean F1=0.55) indicate T=1.2 over-diversifies. Structural metric (SJ) still beats surface (Fleiss) by 0.075 rho advantage. Verdict: FAIL (MVP threshold not met on single subtask).\", \"completed_at\": \"2026-05-21T00:44:30.280Z\"}, \"exp_conll_t12_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T23:41:59.173Z\", \"updated_at\": \"2026-05-21T00:39:01.179Z\", \"hypothesis\": \"CoNLL temperature ablation (T=1.2, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 1.2 --seed 123 --output_dir output/exp_conll_t12_seed123\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123}, \"metrics\": {\"greedy_f1\": 0.9072, \"oracle_f1\": 0.955, \"oracle_headroom\": 0.0478, \"fleiss_kappa_mean\": 0.6675, \"soft_jaccard_mean\": 0.8295, \"rho_fleiss_full\": 0.4086, \"rho_softjaccard_full\": 0.4352, \"rho_fleiss_cond\": 0.3516, \"rho_softjaccard_cond\": 0.3915, \"structural_beats_surface\": true, \"rho_advantage\": 0.0266, \"sample_f1_mean\": 0.8438, \"sample_f1_pct_zero\": 9.1, \"verdict\": \"PASS\"}, \"log_path\": \"output/exp_conll_t12_seed123.log\", \"checkpoint_path\": \"output/exp_conll_t12_seed123/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T00:39:01.179Z\"}, \"exp_conll_t08_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T23:41:58.169Z\", \"updated_at\": \"2026-05-21T00:38:55.958Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.8, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 0.8 --seed 123 --output_dir output/exp_conll_t08_seed123\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123}, \"metrics\": {\"greedy_f1\": 0.9068, \"oracle_f1\": 0.9466, \"oracle_headroom\": 0.0398, \"fleiss_kappa_mean\": 0.8246, \"soft_jaccard_mean\": 0.9201, \"rho_fleiss_full\": 0.4718, \"rho_softjaccard_full\": 0.4846, \"rho_fleiss_cond\": 0.4444, \"rho_softjaccard_cond\": 0.462, \"structural_beats_surface\": true, \"rho_advantage\": 0.0128, \"sample_f1_mean\": 0.8897, \"sample_f1_pct_zero\": 6.1, \"verdict\": \"PASS\"}, \"log_path\": \"output/exp_conll_t08_seed123.log\", \"checkpoint_path\": \"output/exp_conll_t08_seed123/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T00:38:55.958Z\"}, \"exp_conll_t05_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T23:41:56.932Z\", \"updated_at\": \"2026-05-21T00:38:53.249Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.5, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 0.5 --seed 123 --output_dir output/exp_conll_t05_seed123\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123}, \"metrics\": {\"greedy_f1\": 0.9073, \"oracle_f1\": 0.9351, \"oracle_headroom\": 0.0278, \"fleiss_kappa_mean\": 0.8941, \"soft_jaccard_mean\": 0.954, \"rho_fleiss_full\": 0.4529, \"rho_softjaccard_full\": 0.4602, \"rho_fleiss_cond\": 0.4493, \"rho_softjaccard_cond\": 0.4566, \"structural_beats_surface\": true, \"rho_advantage\": 0.0072, \"sample_f1_mean\": 0.901, \"sample_f1_pct_zero\": 5.5, \"verdict\": \"PASS\"}, \"log_path\": \"output/exp_conll_t05_seed123.log\", \"checkpoint_path\": \"output/exp_conll_t05_seed123/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T00:38:53.249Z\"}, \"exp_qwen25_32b_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:19:25.428Z\", \"updated_at\": \"2026-05-21T00:18:28.126Z\", \"hypothesis\": \"Qwen2.5-32B-Instruct QLoRA fine-tuning on FewNERD: scaling model from 8B→32B should improve per-sample NER quality, enabling stronger SC diagnostic signals. LoRA r=32, alpha=64, target all attention+FFN projections, 5 epochs, 4×RTX 5090.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"started_at\": \"2026-05-19T06:47:41.246Z\"}, \"notes\": \"2026-05-19 11:36 UTC: step 2177/41180 (5.3%), loss 0.0663, ~2.44s/it, ETA ~26h. checkpoint-2000 saved. PID 804438, 4×5090 87-100% util.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0,1,2,3 FORCE_TORCHRUN=1 NNODES=1 NPROC_PER_NODE=4 llamafactory-cli train /root/autodl-tmp/struct_self_consist_ie/train_config_qwen25_32b_fewnerd_s42.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/llmfactory_train.json\", \"data_count\": 131767, \"model_name\": \"Qwen2.5-32B-Instruct\", \"seed\": 42, \"method\": \"QLoRA-4bit-nf4 (rank=32, alpha=64, target=all)\", \"output_dir\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-32b-fewnerd-qlora-s42\", \"config_path\": \"/root/autodl-tmp/struct_self_consist_ie/train_config_qwen25_32b_fewnerd_s42.yaml\", \"epochs\": 5, \"effective_batch_size\": 16, \"lr\": \"2e-4\", \"gpu_ids\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/train_qwen25_32b_fewnerd_s42.log\", \"pid\": 804438, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-32b-fewnerd-qlora-s42/checkpoint-32000\"}, \"metrics\": {\"total_steps\": 41180, \"epochs\": 5, \"best_checkpoint\": \"checkpoint-32000\", \"best_eval_loss\": 0.0334, \"final_train_loss\": 0.005, \"final_eval_loss\": 0.0412, \"initial_loss\": 0.559, \"training_time_hours\": 38.5, \"lora_rank\": 32, \"lora_alpha\": 64, \"note\": \"Overfitting after epoch ~3.9; best eval_loss at step 32000 (epoch 3.89). Post-training load-best-model OOM (rank2) but all checkpoints saved correctly.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T00:18:28.126Z\"}, \"exp_conll_t_ablation_t12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:41:01.169Z\", \"updated_at\": \"2026-05-20T23:35:53.499Z\", \"hypothesis\": \"CoNLL temperature ablation (T=1.2): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3-dataset temperature-degeneracy frontier. N=8, Qwen3-8B-FT, seed=42.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.2 --seed 42 --output_dir output/exp_conll_t12_seed42\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 2756, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42, \"pid\": 243594, \"gpu\": \"cuda:3\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t12_seed42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t12_seed42/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T23:35:37.422Z\", \"metrics\": {\"greedy_f1\": 0.9071, \"oracle_f1\": 0.9514, \"oracle_headroom\": 0.0443, \"fleiss_kappa\": 0.7092, \"softjaccard_rho_full\": 0.4071, \"softjaccard_rho_cond\": 0.3936, \"fleiss_rho_full\": 0.3786, \"fleiss_rho_cond\": 0.349, \"degen_pct\": 9.22, \"sample_f1_mean\": 0.8452, \"verdict\": \"PASS\"}}, \"exp_conll_t_ablation_t08\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:40:59.474Z\", \"updated_at\": \"2026-05-20T23:35:51.189Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.8): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3-dataset temperature-degeneracy frontier. N=8, Qwen3-8B-FT, seed=42.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.8 --seed 42 --output_dir output/exp_conll_t08_seed42\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 2756, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42, \"pid\": 242682, \"gpu\": \"cuda:2\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t08_seed42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t08_seed42/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T23:35:34.984Z\", \"metrics\": {\"greedy_f1\": 0.9069, \"oracle_f1\": 0.9464, \"oracle_headroom\": 0.0396, \"fleiss_kappa\": 0.8199, \"softjaccard_rho_full\": 0.4498, \"softjaccard_rho_cond\": 0.4373, \"fleiss_rho_full\": 0.4352, \"fleiss_rho_cond\": 0.4128, \"degen_pct\": 6.57, \"sample_f1_mean\": 0.8854, \"verdict\": \"PASS\"}}, \"exp_conll_t_ablation_t05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:40:58.068Z\", \"updated_at\": \"2026-05-20T23:35:48.803Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.5): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3-dataset temperature-degeneracy frontier. N=8, Qwen3-8B-FT, seed=42.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.5 --seed 42 --output_dir output/exp_conll_t05_seed42\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 2756, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42, \"pid\": 242197, \"gpu\": \"cuda:1\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t05_seed42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t05_seed42/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T23:35:32.179Z\", \"metrics\": {\"greedy_f1\": 0.9077, \"oracle_f1\": 0.9372, \"oracle_headroom\": 0.0296, \"fleiss_kappa\": 0.8948, \"softjaccard_rho_full\": 0.4312, \"softjaccard_rho_cond\": 0.4544, \"fleiss_rho_cond\": 0.4519, \"degen_pct\": 5.64, \"sample_f1_mean\": 0.8993, \"verdict\": \"PASS\"}}, \"exp_conll_t05_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:41:11.361Z\", \"updated_at\": \"2026-05-20T23:35:46.566Z\", \"hypothesis\": \"CoNLL T=0.5 temperature point: test low temperature on CoNLL2003 to extend cross-dataset T-ablation evidence beyond SciERC and FewNERD. N=8, Qwen3-8B-FT-CoNLL, seed=42. Complements SciERC T-ablation for 3-dataset degeneracy-temperature comparison.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.5 --seed 42 --collect_logprobs --output_dir output/conll_t05_s42/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003/test.json\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged (Qwen3-8B-FT-CoNLL)\", \"seed\": 42, \"gpu\": \"cuda:3\", \"tmux_session\": \"conll_t05\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/conll_t05_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/conll_t05_s42/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T23:35:29.767Z\", \"metrics\": {\"greedy_f1\": 0.9083, \"oracle_f1\": 0.9376, \"oracle_headroom\": 0.0294, \"fleiss_kappa\": 0.8958, \"softjaccard_rho_full\": 0.4228, \"softjaccard_rho_cond\": 0.4476, \"fleiss_rho_cond\": 0.4443, \"logprob_rho_cond\": 0.3562, \"logprob_auroc_cond\": 0.8102, \"degen_pct\": 5.64, \"sample_f1_mean\": 0.8994, \"verdict\": \"PASS\"}}, \"exp_spider_sc_pilot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T18:41:49.560Z\", \"updated_at\": \"2026-05-20T22:37:08.907Z\", \"hypothesis\": \"SC diagnostic cascade (degeneracy, agreement-correctness correlation, failure mode classification F1-F4) validated on NER structured generation will also manifest in SQL structured generation with GPT-5.5 on Spider-dev (200 examples, N=8, T=1.0), demonstrating cross-task universality. Key adaptation: uses execution-result equivalence (not SQL text) for agreement/degeneracy, since semantically equivalent SQL can have different surface forms.\", \"spec\": {\"command\": \"python run_spider_sc.py --n_samples 8 --temperature 1.0 --seed 42 --output_dir ./results --test_api\", \"server\": \"local (CPU+API)\", \"gpu\": \"cuda:2\", \"data_path\": \"xlangai/spider (HF) + spider databases (sqlite)\", \"data_count\": 200, \"model_name\": \"openai/gpt-5.5 via http://47.94.22.126/v1\", \"seed\": 42, \"bugfixes\": [\"F1-F4 failure modes aligned with NER cascade (F2=low_agreement, F3=high_agreement_wrong)\", \"Degeneracy detection uses execution results instead of SQL text comparison\", \"Converted from vLLM to API-based (CPU+API experiment)\"], \"pid\": 1504303, \"failure_reason\": \"402 API balance exhausted at 125/200 instances\", \"partial_results\": \"125/200 instances completed before API died\", \"log_path\": \"local spider_sc results dir\", \"checkpoint_path\": \"local spider_sc results dir\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T22:05:14.976Z\", \"metrics\": {\"n_instances\": 196, \"n_target\": 200, \"n_skipped\": 2, \"n_samples\": 8, \"temperature\": 1, \"model\": \"gpt-5.5\", \"greedy_acc\": 0.7653, \"mv_acc\": 0.7704, \"oracle_acc\": 0.8061, \"mv_gain_pp\": 0.51, \"degeneracy_rate\": 0.8724, \"spearman_rho\": 0.5501, \"spearman_p\": 6.77e-17, \"kendall_tau\": 0.5259, \"F1_degeneracy_rate\": 0.872, \"F2_low_agreement_rate\": 0, \"F3_high_agree_wrong_rate\": 0.082, \"F4_selection_gap_rate\": 0, \"sc_success_rate\": 0.046, \"nondegen_n\": 25, \"nondegen_greedy_acc\": 0.32, \"nondegen_mv_acc\": 0.36, \"nondegen_oracle_acc\": 0.64, \"nondegen_spearman_rho\": 0.13}, \"notes\": \"Data quality verified: all 196 instances generated AFTER F2/F3 bugfix (code modified 20:47:22, checkpoint started 20:47:52). Zero mismatch between embedded and recomputed failure modes. F1-F4 distribution: F1=87.2%, F2=0%, F3=8.2%, F4=0%, OK=4.6%. F2=0 means SQL has no low-agreement zone (either degenerate or high consensus). Paper-ready. Note: F4 is dead code in SQL context (greedy_correct AND NOT mv_correct never occurs). Cross-task threshold note: SQL uses agreement<0.5 for F2/F3 split, RE uses kappa<0.3.\"}, \"exp_fewrel_re_sc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T21:13:10.685Z\", \"updated_at\": \"2026-05-20T22:08:51.973Z\", \"hypothesis\": \"SC consensus construction improves RE micro-F1 over greedy decoding on FewRel (16 relation types, Wikipedia domain), extending cross-task universality evidence beyond SciERC and DocRED\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python3 -u experiments/fewrel_re_sc/run_fewrel_re_sc.py --model-path /root/autodl-tmp/.hf_cache/Qwen2.5-7B-Instruct --data data/fewrel_re_test_instances.jsonl --output-dir output/fewrel_re_sc --n-samples 8 --temperature 1.0\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewrel_re_test_instances.jsonl\", \"data_count\": 256, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"pid\": 236752, \"gpu\": \"cuda:1\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewrel_re_sc/run.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewrel_re_sc/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T21:20:24.473Z\", \"metrics\": {\"greedy_micro_f1\": 0.0751, \"construction_micro_f1\": 0.0881, \"majority_vote_f1_mean\": 0.0591, \"oracle_f1_mean\": 0.1768, \"fleiss_kappa_mean\": 0.1506, \"soft_jaccard_mean\": 0.3918, \"degeneracy_rate\": 0.0586, \"bootstrap_p_value\": 0.7572, \"failure_modes\": {\"F2_low_agreement\": \"75.8%\", \"F3_high_agreement_low_quality\": \"15.2%\", \"F1_degeneracy\": \"5.9%\", \"none\": \"2.3%\", \"F4_lp_quality_gap\": \"0.8%\"}}, \"notes\": \"Reviewer confirmed: same pattern as SciERC/DocRED RE (low F1, high F2). Micro_f1 and mean_f1 directions diverge: construction micro_f1 > greedy (0.0881 vs 0.0751) but mean_f1 < greedy. Paper uses micro_f1 per D204. Marked negative because bootstrap p=0.7572 (not significant).\"}, \"exp_a2_humaneval_sc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T18:15:14.615Z\", \"updated_at\": \"2026-05-20T22:05:17.728Z\", \"hypothesis\": \"SC failure modes (degeneracy, false agreement) generalize from NER to code generation despite deterministic verification — majority voting on HumanEval will show limited gains over greedy when degeneracy is high, paralleling NER findings.\", \"spec\": {\"command\": \"python -u run_humaneval_sc.py --n_samples 8 --temperature 1.0 --seed 42 --output_dir ./results\", \"server\": \"autodl-5090\", \"pid\": 967645, \"data_path\": \"openai/openai_humaneval (HuggingFace)\", \"data_count\": 164, \"model_name\": \"openai/gpt-5.5\", \"seed\": 42, \"fix_note\": \"v2 rerun: fixed extract_code() strip() -> rstrip() + auto-indent for function body. Previous run had 0/164 pass due to IndentationError.\", \"failure_reason\": \"402 API balance exhausted after indent bugfix. Fix verified (23/23 greedy pass, 179/184 sample pass) but only 24/164 tasks completed before API died.\", \"log_path\": \"autodl-5090 humaneval results dir\", \"checkpoint_path\": \"autodl-5090 humaneval results dir\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-20T22:05:17.728Z\"}, \"exp_b_frontier_sc_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T18:15:19.266Z\", \"updated_at\": \"2026-05-20T22:05:12.564Z\", \"hypothesis\": \"The correlation-selection gap in structured self-consistency (where agreement correlates with accuracy but majority voting fails to improve over greedy) persists even with frontier models (GPT-5.5, Claude Opus 4.6), indicating it is a fundamental structural limitation of entity-level majority voting rather than a model capability issue.\", \"spec\": {\"command\": \"nohup .venv/bin/python -u run_frontier_sc.py --from-hf --n-instances 200 --n-samples 8 --temperature 1.0 --seed 42 --output-dir ./output > frontier_sc.log 2>&1 &\", \"server\": \"local\", \"data_path\": \"HuggingFace DFKI-SLT/few-nerd supervised test split\", \"data_count\": 200, \"model_name\": \"openai/gpt-5.5 + anthropic/claude-opus-4.6 (via OpenRouter)\", \"seed\": 42, \"pid\": 1509955, \"code_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/experiments/frontier_sc/run_frontier_sc.py\", \"log_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/experiments/frontier_sc/frontier_sc.log\", \"checkpoint_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/experiments/frontier_sc/output/\", \"failure_reason\": \"entity_set() TypeError - compute_instance_metrics passed full parsed dict instead of entities list\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-20T22:05:12.564Z\"}, \"exp_docred_re_sc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T19:32:26.943Z\", \"updated_at\": \"2026-05-20T21:07:53.274Z\", \"hypothesis\": \"SC diagnostic cascade (degeneracy, correlation-selection gap, F1-F4 failure modes) generalizes from NER to document-level RE on DocRED, with Qwen2.5-7B-Instruct showing similar failure patterns as seen in SciERC NER and SciERC RE.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python3 experiments/docred_re/run_docred_re_sc.py --model-path /root/autodl-tmp/.hf_cache/Qwen2.5-7B-Instruct --data data/docred_re_instances.jsonl --schema data/docred_schema.json --output-dir output/docred_re_sc\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/docred_re_instances.jsonl\", \"data_count\": 200, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/docred_re_sc/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/docred_re_sc/run.log\"}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"metrics\": {\"greedy_f1_mean\": 0.0284, \"construction_f1_mean\": 0.0338, \"majority_vote_f1_mean\": 0.0263, \"oracle_f1_mean\": 0.0999, \"greedy_micro_f1\": 0.0297, \"construction_micro_f1\": 0.0323, \"fleiss_kappa\": -0.0253, \"soft_jaccard\": 0.2907, \"degeneracy_rate\": 0.035, \"n_instances\": 200, \"failure_modes\": {\"F1_degeneracy\": \"3.5%\", \"F2_low_agreement\": \"94.5%\", \"F3_high_agreement_low_quality\": \"2.0%\"}, \"bootstrap_diff\": 0.0053, \"bootstrap_ci_95\": [-0.004, 0.0149], \"bootstrap_p_value\": 0.1276, \"nondegen_construction_greedy_diff\": 0.0055}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T21:07:53.274Z\"}, \"exp_a3_ace05_re\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T18:15:17.438Z\", \"updated_at\": \"2026-05-20T21:03:51.597Z\", \"hypothesis\": \"Cross-task universality: SC diagnostic cascade on ACE05 Relation Extraction. Closest extension to NER—same structured prediction paradigm, different output structure (entity pairs + relation types). Qwen2.5-7B-Instruct few-shot prompt. If correlation-selection gap exists for RE, the framework covers multiple IE sub-tasks.\", \"spec\": {\"hypothesis\": \"The SC diagnostic cascade (degeneracy, agreement, LP-quality gap) generalizes from NER to Relation Extraction, with failure modes F1-F4 exhibiting analogous distributions on RE because both are span-based structured prediction tasks sharing the same underlying model uncertainty structure.\", \"model_name\": \"Qwen2.5-7B-Instruct\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/re_test_instances.jsonl\", \"data_count\": 397, \"server\": \"autodl-5090-c\", \"seed\": 42, \"command\": \"CUDA_VISIBLE_DEVICES=1 python3 experiments/re_sc/run_re_sc.py --model-path /root/autodl-tmp/.hf_cache/Qwen2.5-7B-Instruct --data data/re_test_instances.jsonl --output-dir output/re_sc --n-samples 8 --temperature 1.0\", \"method\": \"SC diagnostic cascade on RE (few-shot, N=8, T=1.0, XGrammar constrained decoding)\", \"parent\": null, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/re_sc/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/re_sc.log\"}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T21:03:46.444Z\", \"metrics\": {\"greedy_f1_mean\": 0.0777, \"construction_f1_mean\": 0.0599, \"majority_vote_f1_mean\": 0.0491, \"oracle_f1_mean\": 0.1567, \"greedy_micro_f1\": 0.0688, \"construction_micro_f1\": 0.0602, \"fleiss_kappa\": -0.0021, \"soft_jaccard\": 0.2425, \"degeneracy_rate\": 0.0076, \"n_instances\": 397, \"failure_modes\": {\"F1_degeneracy\": \"0.8%\", \"F2_low_agreement\": \"93.5%\", \"F3_high_agreement_low_quality\": \"4.5%\", \"none\": \"1.3%\"}, \"bootstrap_diff\": -0.0178, \"bootstrap_ci_95\": [-0.0334, -0.0024], \"bootstrap_p_value\": 0.989}}, \"exp_b1_scd\": {\"status\": \"PENDING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:12:48.805Z\", \"updated_at\": \"2026-05-20T20:15:56.852Z\", \"hypothesis\": \"Self-Consistency Distillation via theta2n construction pseudo-labels can teach Qwen3-8B-FT to internalize SC benefits: after iterative SCD (M0→M1→M2→M3), greedy F1 should approach N=8 construction F1 (FewNERD target: 0.764 vs current greedy 0.748). CoNLL serves as negative control (construction Δ=-0.4pp, SCD should not help). Transductive setting: pseudo-labels from test set SC outputs.\", \"conclusion\": \"killed\"}, \"eval_scd_fewnerd_fallback\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T19:11:25.544Z\", \"updated_at\": \"2026-05-20T20:15:55.907Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && bash run_scd_fewnerd_eval.sh\\\"\", \"server\": \"autodl-5090-b\", \"gpu\": [\"cuda:0\"], \"pid\": \"270397\", \"log_path\": \"~/runs/struct_self_consist_ie/eval_scd_fewnerd_fallback.log\", \"submitted_at\": \"2026-05-20T19:11:24.918Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"killed\"}, \"exp_b1_scd_fewnerd_curriculum_q\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:17:38.760Z\", \"updated_at\": \"2026-05-20T20:15:55.005Z\", \"hypothesis\": \"Q variant SCD with curriculum ordering: use B2 entity verifier confidence to stratify pseudo-labels (conf>0.8→Round1, 0.5-0.8→Round2, conf<0.5→discard). Curriculum by verifier confidence improves SCD convergence and final greedy F1 vs standard flat SCD on FewNERD.\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scd_fewnerd_fallback_s43.yaml\", \"server\": \"autodl-5090-b\", \"gpu_ids\": [1], \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scd_fewnerd_theta2n_s42.jsonl\", \"data_count\": 32565, \"model_name\": \"Qwen3-8B-FT\", \"seed\": 43, \"note\": \"Fallback standard SCD seed=43 (Q-variant deferred per D189)\"}, \"reproduce\": {\"finished_at\": \"2026-05-20T19:01:52.441Z\"}, \"failure_reason\": \"RETRACTED: cron false positive — training completed successfully (4706/4706 steps, loss=0.023). Original: process dead 5× with no sentinel/W&B\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T19:01:57.213Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T19:02:06.612980+00:00\"}]}, \"notes\": \"M046: SCD metric artifact confirmed. Original +3.84pp was comparing instance-avg F1 baseline (0.7482, gold-filtered n=32565) to micro-F1 post-SCD (0.7866, full n=37648). Unified micro-F1: pre=0.7886 → post=0.7866, Δ=-0.20pp. Instance-avg: pre=0.7719 → post=0.7809, Δ=+0.90pp (much smaller than claimed). SCD does not constitute paper contribution.\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-scd-fallback-lora/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp_b1_scd_fewnerd_fallback.log\", \"metrics\": {\"eval_greedy_f1\": 0.7866, \"eval_greedy_precision\": 0.7663, \"eval_greedy_recall\": 0.808, \"eval_instance_avg_f1\": 0.7809, \"delta_vs_baseline\": 0.0386, \"baseline_greedy_f1\": 0.748, \"total_tp\": 78252, \"total_fp\": 23869, \"total_fn\": 18590, \"n_instances\": 37648}}, \"exp_b1_scd_fewnerd_standard\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:17:37.804Z\", \"updated_at\": \"2026-05-20T20:15:51.708Z\", \"hypothesis\": \"Standard Self-Consistency Distillation on FewNERD: fine-tune Qwen3-8B-FT with theta2n construction pseudo-labels (32,565 instances) mixed 1:1 with gold data. Greedy F1 after SCD should approach N=8 construction F1 (0.764 vs current 0.748). Transductive setting: pseudo-labels from test set SC outputs.\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scd_fewnerd_s42.yaml\", \"server\": \"autodl-5090-b\", \"gpu_ids\": [0], \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scd_fewnerd_theta2n_s42.jsonl\", \"data_count\": 32565, \"model_name\": \"Qwen3-8B-FT\", \"seed\": 42, \"pid\": 207109, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-scd-lora/\"}, \"reproduce\": {\"finished_at\": \"2026-05-20T19:13:25.333Z\"}, \"failure_reason\": \"RETRACTED: cron false positive — training completed successfully (4706/4706 steps, train_loss=0.023, eval_loss=0.0329). Original: process dead 5× with no sentinel/W&B\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T19:13:26.395Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T19:13:35.804759+00:00\"}]}, \"notes\": \"M046: SCD metric artifact confirmed. Original +3.3pp was comparing instance-avg F1 baseline (0.7482, gold-filtered n=32565) to micro-F1 post-SCD (0.7813, full n=37648). Unified micro-F1: pre=0.7886 → post=0.7813, Δ=-0.73pp. SCD does not improve NER performance.\", \"metrics\": {\"train_loss\": 0.023, \"eval_loss\": 0.0329, \"steps\": 4706, \"epochs\": 2, \"train_runtime_hours\": 7.14}}, \"exp_b1_scd_threshold_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:17:42.163Z\", \"updated_at\": \"2026-05-20T20:00:50.883Z\", \"hypothesis\": \"Construction threshold sweep for SCD pseudo-label generation on FewNERD: θ∈{1/N, 2/N, 3/N, 0.5}. Higher θ = more conservative pseudo-labels (higher precision, lower recall). Optimal θ balances pseudo-label quality vs quantity for SCD training effectiveness.\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scd_fewnerd_theta3_s42.yaml\", \"server\": \"autodl-5090-b\", \"gpu_ids\": [3], \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scd_fewnerd_theta3n_s42.jsonl\", \"data_count\": 32565, \"model_name\": \"Qwen3-8B-FT\", \"seed\": 42, \"note\": \"theta=3/N ablation\"}, \"reproduce\": {\"finished_at\": \"2026-05-20T20:00:47.950Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-20T20:00:50.883Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T20:00:57.832218+00:00\"}]}}, \"exp_tlow_fewnerd_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:40:52.432Z\", \"updated_at\": \"2026-05-20T19:39:38.613Z\", \"hypothesis\": \"Lower temperature (T=0.5) sampling on FewNERD produces less diverse but higher-quality samples that, when combined with T=1.0 samples in heterogeneous-temperature selection, improve self-consistency-based quality estimation compared to single-temperature baselines.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen25-7b-fewnerd-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.5 --seed 42 --collect_logprobs --output_dir output/exp_tlow_fewnerd_t05_s42/\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen25-7b-fewnerd-merged\", \"seed\": 42, \"pid\": 221493, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_tlow_fewnerd_t05_s42.log\"}, \"checkpoint_path\": \"output/exp_tlow_fewnerd_t05_s42/\", \"log_path\": \"output/exp_tlow_fewnerd_t05_s42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T19:39:38.613Z\"}, \"exp_asb_adaptive_budget\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:37:33.233Z\", \"updated_at\": \"2026-05-20T19:37:37.412Z\", \"hypothesis\": \"Instance-level features from cheap N=2 subsamples (degeneracy, agreement, entity count, logprob variance, text length) can predict optimal per-instance sample count, enabling adaptive budget allocation that outperforms uniform allocation under a fixed total budget.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python /root/autodl-tmp/struct_self_consist_ie/artifacts/experiments/asb/run_asb.py --data_paths /root/autodl-tmp/struct_self_consist_ie/output/exp_021_inference/samples.jsonl,/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed42/samples.jsonl,/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16/samples.jsonl --dataset_names FewNERD,SciERC,CoNLL --output_dir /root/autodl-tmp/struct_self_consist_ie/output/exp_asb_adaptive_budget/ --seed 42\\\"\", \"server\": \"autodl-5090\", \"gpu\": [], \"pid\": \"943151\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_asb_adaptive_budget.log\", \"submitted_at\": \"2026-05-20T17:55:06.477Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"output/exp_asb_adaptive_budget/asb_results.json\", \"wall_clock_seconds\": 215.1, \"gpu_hours\": 0.0}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T17:58:41.592Z\", \"metrics\": {\"v2_fixed\": true, \"fixes\": [\"removed greedy_f1 feature (data leak via gold labels)\", \"max_n-aware adaptive_allocation\", \"K-fold downstream eval (no train=test leak)\", \"micro-F1 (global TP/FP/FN)\"], \"fewnerd\": {\"uniform_n8_micro_f1\": 0.7842, \"adaptive_micro_f1\": 0.7842, \"delta_adaptive_uniform\": 0, \"oracle_micro_f1\": 0.7842, \"greedy_micro_f1\": 0.7911, \"best_predictor\": \"MLP\", \"n_instances\": 32565, \"max_n\": 8, \"note\": \"max_n=budget=8, no room for reallocation\"}, \"scierc\": {\"uniform_n8_micro_f1\": 0.6657, \"adaptive_micro_f1\": 0.6657, \"delta_adaptive_uniform\": 0, \"oracle_micro_f1\": 0.6657, \"greedy_micro_f1\": 0.6649, \"best_predictor\": \"MLP\", \"n_instances\": 529, \"max_n\": 8, \"note\": \"max_n=budget=8, no room for reallocation\"}, \"conll\": {\"uniform_n8_micro_f1\": 0.9128, \"adaptive_micro_f1\": 0.9095, \"delta_adaptive_uniform\": -0.0033, \"oracle_micro_f1\": 0.9139, \"delta_oracle_uniform\": 0.0012, \"greedy_micro_f1\": 0.9124, \"adaptive_fold_mean\": 0.91, \"adaptive_fold_std\": 0.0044, \"best_predictor\": \"RandomForest\", \"n_instances\": 2756, \"max_n\": 16}, \"top_features\": [\"degen_rate_n2\", \"agreement_n2\", \"entity_count_n2\"], \"key_finding\": \"After fixing data leak + train=test leak + max_n bug, adaptive allocation shows no improvement over uniform. FewNERD/SciERC have max_n=budget=8 (no reallocation possible). CoNLL (max_n=16) shows slight negative delta (-0.0033). Previous positive results were artifacts of methodological bugs.\"}}, \"exp_e_theta_adaptive\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:31:49.319Z\", \"updated_at\": \"2026-05-20T19:24:52.991Z\", \"hypothesis\": \"Threshold-Adaptive SC: N inverse scaling (D191) proves θ choice determines scaling direction. A learned θ predictor (input: degeneracy_level, lp_variance, N, dataset, model) can select per-instance optimal θ, closing the gap between fixed θ=0.5 and oracle θ. Leave-one-config-out CV on 16 configs from existing N=8/16 data. 5 variants: LogReg/MLP × feature subsets + degeneracy-only baseline.\", \"spec\": {\"checkpoint_path\": \"N/A (CPU predictor, no model checkpoint)\", \"log_path\": \"N/A (inline evaluation)\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T19:24:52.991Z\"}, \"exp_cross_model_consistency\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T09:30:47.928Z\", \"updated_at\": \"2026-05-20T19:03:33.786Z\", \"hypothesis\": \"Cross-model entity construction (mixing Qwen and LLaMA outputs) produces higher-quality entity spans than single-model construction, because inter-model agreement filters out model-specific hallucinations while preserving genuinely supported entities.\", \"metrics\": {\"scierc\": {\"n_filtered\": 529, \"qwen_greedy_f1\": 0.6453, \"llama_greedy_f1\": 0.646, \"degeneracy\": {\"pure_qwen\": 0.1323, \"pure_llama\": 0.1777, \"mixed\": 0.0964}, \"construction_f1\": {\"pure_qwen_uniform\": 0.6449, \"pure_qwen_vc\": 0.6413, \"pure_llama_uniform\": 0.6545, \"pure_llama_vc\": 0.649, \"mixed_uniform\": 0.6625, \"mixed_vc\": 0.6591}, \"bootstrap\": {\"mixed_uni_vs_pure_qwen_uni\": {\"delta_pp\": 1.77, \"p\": 0.0102, \"ci\": [0.27, 3.28]}, \"mixed_vc_vs_pure_qwen_vc\": {\"delta_pp\": 1.77, \"p\": 0.0093, \"ci\": [0.33, 3.27]}, \"mixed_uni_vs_pure_llama_uni\": {\"delta_pp\": 0.81, \"p\": 0.1304, \"ci\": [-0.59, 2.25]}, \"mixed_vc_vs_pure_llama_vc\": {\"delta_pp\": 1.01, \"p\": 0.0702, \"ci\": [-0.32, 2.38]}}}, \"fewnerd\": {\"n_filtered\": 32565, \"qwen_greedy_f1\": 0.7478, \"llama_greedy_f1\": 0.7841, \"degeneracy\": {\"pure_qwen\": 0.1004, \"pure_llama\": 0.2336, \"mixed\": 0.1158}, \"construction_f1\": {\"pure_qwen_uniform\": 0.7499, \"pure_qwen_vc\": 0.7448, \"pure_llama_uniform\": 0.7873, \"pure_llama_vc\": 0.7869, \"mixed_uniform\": 0.7916, \"mixed_vc\": 0.7898}, \"bootstrap\": {\"mixed_uni_vs_pure_qwen_uni\": {\"delta_pp\": 4.17, \"p\": 0, \"ci\": [3.92, 4.4]}, \"mixed_vc_vs_pure_qwen_vc\": {\"delta_pp\": 4.5, \"p\": 0, \"ci\": [4.25, 4.75]}, \"mixed_uni_vs_pure_llama_uni\": {\"delta_pp\": 0.42, \"p\": 0, \"ci\": [0.27, 0.58]}, \"mixed_vc_vs_pure_llama_vc\": {\"delta_pp\": 0.29, \"p\": 0.0001, \"ci\": [0.13, 0.45]}}}}, \"conclusion\": \"success\", \"notes\": \"B5 cross-model consistency on SciERC + FewNERD. Mixed (4Q+4L) consistently outperforms pure-model construction on both datasets. FewNERD: mixed sig. beats pure LLaMA (+0.42pp uni p=0, +0.29pp VC p=0.0001) and pure Qwen (+4.17pp uni, +4.50pp VC, all p=0). SciERC: mixed sig. beats pure Qwen (+1.77pp uni p=0.01, +1.77pp VC p=0.009); vs pure LLaMA marginal (+0.81pp uni p=0.13, +1.01pp VC p=0.07). Cross-model diversity reduces degeneracy (FewNERD mixed 11.6% vs LLaMA 23.4%; SciERC mixed 9.6% vs LLaMA 17.8%). Note: SciERC greedy F1 lower than prior run (0.645 vs 0.748) — likely different eval scope (gold filter 529 vs prior 551).\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"spec\": {\"command\": \"bash code/run_cross_model.sh\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_026_t10_seed42/samples.jsonl + output/exp007_llama_inference/samples.jsonl + output/exp_021_inference/samples.jsonl + output/llama_fewnerd_s42/samples.jsonl\", \"data_count\": 76398, \"model_name\": \"cross-model (Qwen + LLaMA)\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_cross_model_consistency\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_cross_model_consistency\"}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_cross_model_consistency\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_cross_model_consistency\", \"completed_at\": \"2026-05-20T19:03:33.786Z\"}, \"exp_backup3_distill_verifier\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:40:49.676Z\", \"updated_at\": \"2026-05-20T18:47:37.248Z\", \"hypothesis\": \"A supervised entity-level binary classifier (trained on 6 lightweight features: LP score, agreement ratio, degeneracy flag, span length, type consistency, N) can learn cross-dataset entity correctness signals that outperform unsupervised majority voting for entity construction, because the classifier can jointly weight multiple complementary signals that MV ignores.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python /root/autodl-tmp/struct_self_consist_ie/run_distill_verifier.py --seed 42\", \"server\": \"autodl-5090\", \"data_path\": {\"scierc\": \"output/exp_026_t10_seed42/samples.jsonl (551 inst, N=8)\", \"conll\": \"output/exp_002_conll_n16/samples.jsonl (3453 inst, N=16→subsample to 8)\", \"fewnerd\": \"output/exp_021_inference/samples.jsonl (37648 inst, N=8)\"}, \"data_count\": \"41652 instances total (~551+3453+37648)\", \"model_name\": \"LR+RF+MLP ensemble (sklearn)\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/distill_verifier/distill_verifier_results.json\", \"log_path\": \"/tmp/distill_verifier.log\", \"completed_at\": \"2026-05-20T18:47:30.099Z\", \"metrics\": {\"aggregate\": {\"LR\": {\"mean_auroc\": 0.8747, \"std_auroc\": 0.0563, \"mean_delta_f1\": -0.0014}, \"RF\": {\"mean_auroc\": 0.8752, \"std_auroc\": 0.0588, \"mean_delta_f1\": -0.0006}, \"MLP\": {\"mean_auroc\": 0.8744, \"std_auroc\": 0.0578, \"mean_delta_f1\": 0.0011}}, \"per_fold\": {\"scierc\": {\"LR\": {\"auroc\": 0.8009, \"std_mv_f1\": 0.6643, \"best_weighted_f1\": 0.6659, \"delta_f1\": 0.0016}, \"RF\": {\"auroc\": 0.7988, \"best_weighted_f1\": 0.6647, \"delta_f1\": 0.0004}, \"MLP\": {\"auroc\": 0.798, \"best_weighted_f1\": 0.6655, \"delta_f1\": 0.0012}}, \"conll\": {\"LR\": {\"auroc\": 0.9376, \"std_mv_f1\": 0.9074, \"best_weighted_f1\": 0.9049, \"delta_f1\": -0.0025}, \"RF\": {\"auroc\": 0.9419, \"best_weighted_f1\": 0.908, \"delta_f1\": 0.0006}, \"MLP\": {\"auroc\": 0.9379, \"best_weighted_f1\": 0.9075, \"delta_f1\": 0.0001}}, \"fewnerd\": {\"LR\": {\"auroc\": 0.8855, \"std_mv_f1\": 0.7819, \"best_weighted_f1\": 0.7786, \"delta_f1\": -0.0034}, \"RF\": {\"auroc\": 0.885, \"best_weighted_f1\": 0.7791, \"delta_f1\": -0.0029}, \"MLP\": {\"auroc\": 0.8872, \"best_weighted_f1\": 0.7839, \"delta_f1\": 0.002}}}, \"feature_importance_LR_scierc\": {\"agreement_ratio\": 1.651, \"lp_score\": 0.424, \"span_length\": -0.15, \"type_consistency\": 0.128, \"degeneracy_flag\": 0.043, \"n_samples\": 0}}}, \"exp_backup1_het_temp\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:09:31.094Z\", \"updated_at\": \"2026-05-20T18:15:37.574Z\", \"hypothesis\": \"Heterogeneous-Temperature Sampling: MRSC/LSC negative results prove entity-level correction cannot close the selection gap. F4 degeneracy analysis shows T=0.7 has ~62% degeneracy (too homogeneous) while T=1.0 has more diversity but noisier entities. Mixing samples from different temperatures (k from T_low + (8-k) from T_high) breaks temperature-specific degeneracy patterns: low-T samples provide precise entities, high-T samples provide diversity. Mixed-T N=8 pool should achieve lower degeneracy than pure T_low and higher construction F1 than pure T_high. Hypothesis source: entity-level methods (MRSC weighted re-prompting, LSC latent aggregation) both failed → pivot to sampling-level diversity improvement.\", \"parent\": \"exp_mrsc_multi_round\", \"spec\": {\"command\": \"bash /root/autodl-tmp/struct_self_consist_ie/run_het_temp_all.sh\", \"server\": \"autodl-5090\", \"gpu\": [], \"pid\": \"948780\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_backup1_het_temp.log\", \"submitted_at\": \"2026-05-20T18:13:20.732Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 134.1, \"gpu_hours\": 0.0}, \"metrics\": {\"t08_vs_t10\": {\"seed42\": {\"pure_t_low_f1\": 0.6755, \"pure_t_high_f1\": 0.6643, \"best_mix\": \"5:3\", \"best_mix_f1\": 0.6708, \"delta_vs_low\": -0.0046, \"delta_vs_high\": 0.0066}, \"seed123\": {\"pure_t_low_f1\": 0.6659, \"pure_t_high_f1\": 0.6681, \"best_mix\": \"6:2\", \"best_mix_f1\": 0.6655, \"delta_vs_low\": -0.0004, \"delta_vs_high\": -0.0026}, \"seed456\": {\"pure_t_low_f1\": 0.6675, \"pure_t_high_f1\": 0.6663, \"best_mix\": \"4:4\", \"best_mix_f1\": 0.6654, \"delta_vs_low\": -0.002, \"delta_vs_high\": -0.0008}}, \"t05_vs_t10\": {\"seed42\": {\"pure_t_low_f1\": 0.663, \"pure_t_high_f1\": 0.6643, \"best_mix\": \"5:3\", \"best_mix_f1\": 0.6654, \"delta_vs_low\": 0.0024, \"delta_vs_high\": 0.0011}, \"seed123\": {\"pure_t_low_f1\": 0.6665, \"pure_t_high_f1\": 0.6681, \"best_mix\": \"2:6\", \"best_mix_f1\": 0.6671, \"delta_vs_low\": 0.0006, \"delta_vs_high\": -0.001}, \"seed456\": {\"pure_t_low_f1\": 0.6686, \"pure_t_high_f1\": 0.6663, \"best_mix\": \"4:4\", \"best_mix_f1\": 0.6682, \"delta_vs_low\": -0.0004, \"delta_vs_high\": 0.002}}, \"degeneracy\": {\"t05_mean\": 0.356, \"t08_mean\": 0.178, \"t10_mean\": 0.126}, \"max_delta_any_combo\": 0.0066}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T18:15:34.876Z\", \"notes\": \"Heterogeneous temperature mixing provides no consistent F1 improvement over pure single-temperature sampling on SciERC (551 instances, 3 seeds, 2 temp pairs). All F1 deltas within ±0.005, inconsistent direction across seeds. Mixing does reduce degeneracy (T=0.5: 35%→17%) but this doesn't translate to F1 gain. The pure T_low vs T_high F1 gap is already tiny (~0.001-0.01), leaving no room for mixing to exploit. Joins MRSC/LSC as evidence that sampling-level interventions cannot improve construction F1 when the bottleneck is not sample diversity.\"}, \"exp_a1_spider_sql_sc\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T18:15:12.865Z\", \"updated_at\": \"2026-05-20T18:15:33.104Z\", \"hypothesis\": \"Cross-task universality: SC diagnostic cascade (degeneracy, LP-quality gap, agreement-correctness correlation) applies to SQL structured generation on Spider. Qwen2.5-7B-Instruct base model, 200 dev examples, N=8 T=1.0, execution accuracy evaluation. If F1-F4 failure modes exist in SQL, the framework generalizes beyond NER.\", \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:2\"}, \"exp_esj_entity_self_judgment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:31:53.721Z\", \"updated_at\": \"2026-05-20T17:44:33.778Z\", \"hypothesis\": \"Entity-Level Self-Judgment: F4 diagnostic proves 4/5 signals are instance-level only, LP is per-sample but compressed. ESJ provides true per-sample-per-entity signal via yes/no verification prompts. ESJ-weighted entity construction should outperform majority vote by leveraging entity-level confidence scores that structural signals cannot provide. Parent: exp_e2_mixture_of_signals (F4 LP-only diagnostic).\", \"parent\": \"exp_e2_mixture_of_signals\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-20T15:37:30.954Z\"}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python run_esj.py --base_model_path checkpoints/qwen25-7b-fewnerd-merged --data_path output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl --output_dir output/exp_esj_entity_self_judgment --batch_size 8\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl\", \"data_count\": 37648, \"model_name\": \"qwen25-7b-fewnerd-merged\", \"seed\": 42, \"pid\": 218678, \"gpu\": \"cuda:1\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_esj_entity_self_judgment.log\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-fewnerd-merged\", \"eval_data\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl\", \"n_verification_prompts\": 153649, \"estimated_runtime_hours\": 2.5, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_esj_entity_self_judgment/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T17:44:33.778Z\"}, \"exp_b3_prompted_diversity\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:12:51.750Z\", \"updated_at\": \"2026-05-20T17:40:45.878Z\", \"hypothesis\": \"Structurally different prompt templates (expert persona, descriptive types, recall-focused) generate more diverse N=8 samples than repeating a single template, improving entity construction F1 via broader coverage of the entity space.\", \"conclusion\": \"killed\", \"metrics\": {\"single_vc_weighted_f1\": 0.7723, \"multi_vc_weighted_f1\": 0.7311, \"delta_vc\": -0.0412, \"single_lp_weighted_f1\": 0.7665, \"multi_lp_weighted_f1\": 0.7308, \"delta_lp\": -0.0356, \"single_theta2n_f1\": 0.7618, \"multi_theta2n_f1\": 0.7269, \"delta_theta2n\": -0.0349, \"single_unique_entities\": 5.29, \"multi_unique_entities\": 4.06, \"within_template_jaccard\": 0.474, \"cross_template_jaccard\": 0.67, \"verdict\": \"Multi-template strictly worse. Templates converge to similar outputs; non-standard templates add noise, diluting construction signals.\"}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python /root/autodl-tmp/struct_self_consist_ie/code/exp_b3_prompted_diversity.py --phase both --num_instances 3000 --seed 42\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 3000, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"completed_at\": \"2026-05-20T17:40:45.878Z\"}, \"exp_mrsc_multi_round\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:37:27.523Z\", \"updated_at\": \"2026-05-20T17:12:53.641Z\", \"hypothesis\": \"Multi-Round Iterative SC: N inverse scaling reveals disputed entities cause failures. Focused re-prompting on disputed entities (agreement < 0.6) with weighted aggregation (Round 2 weight=2) should reduce error rate on disputed entities without affecting non-disputed ones, closing part of the selection gap through iterative refinement rather than single-round aggregation.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-20T15:39:10.190Z\"}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python /root/autodl-tmp/struct_self_consist_ie/code/run_mrsc.py --base_model_path /root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-fewnerd-merged --data_path /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl --output_dir /root/autodl-tmp/struct_self_consist_ie/output/exp_mrsc_multi_round --batch_size 16\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl\", \"data_count\": 37648, \"model_name\": \"qwen25-7b-fewnerd-merged\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_mrsc_multi_round\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_mrsc_multi_round.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T17:12:53.641Z\"}, \"exp_lsc_latent_sc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:37:31.881Z\", \"updated_at\": \"2026-05-20T17:11:49.135Z\", \"hypothesis\": \"Latent Self-Consistency: F4 diagnostic proves LP is compressed (median range 0.041 nats). Hidden states contain richer per-sample information than scalar LP. Entity-level mean-pooled hidden state representations enable latent aggregation (centroid selection, latent confidence scoring, clustering) that bypasses LP compression and provides discriminative per-sample ranking unavailable from output-space signals.\", \"parent\": \"exp_e2_mixture_of_signals\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-20T15:39:11.609Z\"}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python run_lsc.py --base_model_path qwen25-7b-fewnerd-merged --data_path fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl --max_instances 2000\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl\", \"data_count\": 2000, \"model_name\": \"qwen25-7b-fewnerd-merged\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-fewnerd-merged\", \"eval_data\": \"FewNERD test (gold-filtered, n=2000)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_lsc_latent_sc\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_lsc_latent_sc.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T16:51:53.120Z\", \"metrics\": {\"centroid_selection_f1\": 0.7593, \"lp_selection_f1\": 0.7845, \"latent_entity_conf_f1\": 0.8385, \"majority_vote_f1\": 0.8366, \"greedy_f1\": 0.7793, \"oracle_f1\": 0.8668, \"lp_vs_latent_rho\": 0.518, \"entity_match_rate\": 0.9945, \"n_instances\": 2000, \"runtime_s\": 507}}, \"exp_14b_inference_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T14:36:25.505Z\", \"updated_at\": \"2026-05-20T15:11:54.487Z\", \"hypothesis\": \"14B Qwen2.5 inference on SciERC (N∈{1,2,4,8,16}): correlation-selection gap pattern should be consistent at 14B scale with intermediate degeneracy rates between 7B and 32B.\", \"reproduce\": {\"finished_at\": \"2026-05-20T14:48:16.272Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-20T14:48:17.102Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T14:48:25.726567+00:00\"}]}}, \"exp_qwen25_14b_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-19T06:19:31.620Z\", \"updated_at\": \"2026-05-20T14:12:35.350Z\", \"hypothesis\": \"The correlation-selection gap pattern is consistent at 14B scale, filling the gap between 8B and 32B. Qwen2.5-14B QLoRA fine-tuned on FewNERD should show intermediate degeneracy rates and similar signal ranking patterns, providing a smooth scaling curve for the diagnostic findings.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:0,cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:0,cuda:1\", \"started_at\": \"2026-05-19T06:47:43.938Z\"}, \"notes\": \"2026-05-19 12:47 UTC: RECOVERED from false-positive startup recovery failure. Step 6483/41180 (15.7%), loss 0.0608, ~2.2s/it, ETA ~21h. checkpoint-6000 saved. screen train_14b_s42 PID 56766, GPU 0,1 95-96% util. Cron registered on PID 56773.\", \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"completed_at\": \"2026-05-19T12:44:29.453Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"2026-05-19 11:36 UTC: step 4934/41180 (12.0%), loss 0.067, ~2.15s/it, ETA ~22h. checkpoint-4000 saved. screen train_14b_s42, 2×5090 76-77% util.\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0,1 FORCE_TORCHRUN=1 NNODES=1 NPROC_PER_NODE=2 llamafactory-cli train train_config_qwen25_14b_fewnerd_s42.yaml\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/llmfactory_train.json\", \"data_count\": 131767, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"gpu_ids\": [\"cuda:0\", \"cuda:1\"], \"screen_session\": \"train_14b_s42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/train_14b_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-14b-fewnerd-qlora-s42/\"}, \"metrics\": {\"epoch\": 5, \"train_loss\": 0.0348, \"eval_loss\": 0.0323, \"train_runtime_hours\": 29.8, \"train_samples_per_second\": 6.141, \"train_steps_per_second\": 0.384, \"total_steps\": 41180}, \"conclusion\": \"success\"}, \"exp_b1_scd_conll_control\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:17:40.591Z\", \"updated_at\": \"2026-05-20T13:08:32.832Z\", \"hypothesis\": \"Negative control: SCD on CoNLL where construction gain is negative (-0.4pp, high degeneracy 70%). If SCD learns from construction pseudo-labels, it should NOT improve greedy F1 on a dataset where construction itself hurts. Expected: no improvement or slight degradation. Validates SCD mechanism.\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scd_conll_s42.yaml\", \"server\": \"autodl-5090-b\", \"gpu_ids\": [2], \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scd_conll_theta2n_s42.jsonl\", \"data_count\": 3453, \"model_name\": \"Qwen3-8B-FT-CoNLL\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll-scd-lora\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scd_conll_s42.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-20T12:14:27.727Z\"}, \"failure_reason\": \"OVERRIDE: Training completed normally (690/690 steps, loss=0.0359). Cron misjudged as failed. Pending eval inference.\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T12:14:30.260Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T12:14:35.853775+00:00\"}]}, \"metrics\": {\"pre_scd_greedy_f1\": 0.9078, \"post_scd_greedy_f1\": 0.9184, \"delta_pp\": 1.06, \"training_steps\": 690, \"final_loss\": 0.0359, \"negative_control_confirmed\": false, \"note\": \"SURPRISE: SCD improved CoNLL F1 by +1.06pp despite negative construction gain. Possible explanations: (1) SCD provides general training benefit (more data), (2) additional training steps alone improve, (3) SCD mechanism doesn't require positive construction gain.\"}}, \"exp_b2_v4_inverse_frequency\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T12:50:51.737Z\", \"updated_at\": \"2026-05-20T12:51:06.312Z\", \"hypothesis\": \"Inverse-frequency weighting of entity features (agreement_count, vc, sj normalized by log(1+type_freq)) improves cross-domain generalization by reducing dominance of high-frequency entity types. Two variants: A) replace original features, B) augment as additional features.\", \"conclusion\": \"negative\", \"metrics\": {\"variant_a_replace_fold3_lgb_auc\": 0.834, \"variant_a_replace_fold3_ece\": 0.2188, \"variant_a_f1_delta\": -0.013, \"variant_b_augment_fold3_lgb_auc\": 0.8541, \"variant_b_augment_fold3_ece\": 0.1934, \"variant_b_f1_delta\": -0.009, \"sj_ifw_std_reduction\": \"54% (0.138→0.063)\", \"ac_ifw_std_reduction\": \"10% (0.122→0.110)\", \"verdict\": \"IFW improves stability but reduces discriminative power. Augment variant neutral. Replace variant harmful.\"}, \"parent\": \"exp_b2_entity_verifier\"}, \"exp_b2_v3_domain_invariant\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T12:50:49.948Z\", \"updated_at\": \"2026-05-20T12:51:00.972Z\", \"hypothesis\": \"Removing domain-specific features (dataset_enc, entity_type distributions) forces the verifier to rely on domain-invariant signals, improving cross-domain generalization at the cost of some discriminative power. If LGB AUC improves on held-out domains, domain features were causing negative transfer.\", \"conclusion\": \"negative\", \"metrics\": {\"fold3_fewnerd_lgb_auc\": 0.8562, \"fold3_fewnerd_xgb_auc\": 0.8518, \"fold3_ece\": 0.1373, \"fold2_scierc_lgb_auc\": 0.8152, \"fold2_scierc_xgb_auc\": 0.8163, \"vs_v2_fold3_lgb_delta\": 0.0085, \"vs_v2_fold2_lgb_delta\": 0.0146, \"top_features\": \"agreement_count (58.4%) + vc (30.3%) = 88%\", \"verdict\": \"LGB AUC improved by removing domain features, confirming negative transfer. But ECE still high, F1 delta still negative.\"}, \"parent\": \"exp_b2_entity_verifier\"}, \"exp_b2_v2_multi_domain_joint\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T12:50:09.686Z\", \"updated_at\": \"2026-05-20T12:50:18.610Z\", \"hypothesis\": \"Joint multi-domain training (CoNLL+SciERC+FewNERD LODO) improves entity verifier AUC and cross-domain construction F1 by exposing the model to diverse entity patterns. Tests whether training data diversity overcomes the calibration gap that caused B2 original to fail on FewNERD.\", \"conclusion\": \"negative\", \"metrics\": {\"fold3_fewnerd_lgb_auc\": 0.8477, \"fold3_fewnerd_xgb_auc\": 0.8603, \"fold3_fewnerd_f1_delta\": -0.008, \"fold3_ece\": 0.136, \"fold4_iid_ece\": 0.007, \"vs_b2_original_lgb_auc_delta\": 0.014, \"vs_b2_original_xgb_auc_delta\": 0.032, \"verdict\": \"AUC improved but F1 still negative. Cross-domain calibration gap unsolved.\"}, \"parent\": \"exp_b2_entity_verifier\"}, \"exp_b2_entity_verifier\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T10:13:41.037Z\", \"updated_at\": \"2026-05-20T12:28:21.280Z\", \"hypothesis\": \"An XGBoost/LightGBM entity-level verifier trained on agreement_count, VC, LP features can predict whether entity candidates are in gold annotations, enabling post-hoc filtering or score-weighted construction that improves over greedy baseline, with cross-dataset generalization from CoNLL+SciERC to FewNERD+WNUT.\", \"metrics\": {\"oof_auc\": 0.9233, \"oof_path_a_f1_delta\": 0.003, \"oof_path_b_f1_delta\": -0.0157, \"oof_greedy_f1\": 0.8216, \"oof_path_a_f1\": 0.8246, \"oof_majority_vote_f1\": 0.8048, \"leakage_pct\": 91, \"original_delta_pp\": 3.62, \"oof_delta_pp\": 0.3, \"per_dataset\": {\"scierc\": \"+1.28pp\", \"conll\": \"+0.55pp\", \"fewnerd\": \"+0.02pp\"}, \"verdict\": \"B2 verifier gain was 91% leakage. OOF Path A +0.30pp not significant. NOT suitable for paper §5.\", \"n_inverse_scaling_validation\": {\"subset_n\": 4351, \"full_n\": 32565, \"subset_greedy_f1\": 0.7926, \"full_greedy_f1\": 0.7913, \"verdict\": \"Not a bug. Representative subset. Paper should note subset size.\"}}, \"conclusion\": \"negative\"}, \"exp_a2_degen_regression\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T10:13:37.615Z\", \"updated_at\": \"2026-05-20T10:13:55.891Z\", \"hypothesis\": \"Degeneracy rate is primarily driven by task difficulty (dataset entropy ceiling) rather than model capability, with a positive correlation between base F1 and degeneracy — easy tasks with high F1 produce degenerate outputs because the model has already converged.\", \"metrics\": {\"n_points\": 30, \"linear_r2\": 0.414, \"quadratic_r2\": 0.592, \"spearman_rho\": 0.519, \"spearman_p\": 0.0033, \"linear_coeff\": \"degen = 129.5 × F1 - 56.9\", \"key_finding\": \"degeneracy driven by dataset difficulty (entropy ceiling), not model capability\"}, \"conclusion\": \"success\"}, \"exp_e1_signal_routing\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T10:13:34.839Z\", \"updated_at\": \"2026-05-20T10:13:52.098Z\", \"hypothesis\": \"A config-level signal router (RF/LR) can predict the optimal construction signal per config from features (degeneracy_rate, base_f1, oracle_headroom), outperforming always-LP baseline. Router ΔF1 should exceed always-LP ΔF1.\", \"metrics\": {\"n_configs\": 16, \"rf_loo_accuracy\": 0.562, \"router_avg_delta_f1\": 0.39, \"always_lp_delta_f1\": 0.15, \"oracle_delta_f1\": 0.56, \"top_features\": [\"oracle_headroom\", \"degeneracy_rate\", \"base_f1\"], \"label_dist\": {\"lp_selection\": 6, \"none\": 5, \"consensus_theta2n\": 3, \"consensus_lp_weighted\": 1, \"majority_vote\": 1}}, \"conclusion\": \"success\", \"notes\": \"E1 signal routing. RF 56.2% LOO accuracy (below 60% target) but router ΔF1 +0.39pp > always-LP +0.15pp (2.6× improvement, target met). Low accuracy due to small n=16 and class imbalance. D176: appendix-only, not main claim.\"}, \"exp_pareto_diversity_quality\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T09:31:45.421Z\", \"updated_at\": \"2026-05-20T09:31:58.776Z\", \"hypothesis\": \"There exists a Pareto frontier in the diversity (1-degeneracy) vs construction quality (ΔF1) space across temperature configurations. Well-separated temperature mixing (T=0.7+T=1.0) achieves Pareto optimality for both uniform and VC construction, while VC-weighted construction flattens the trade-off slope, reducing the diversity cost of quality.\", \"metrics\": {\"dataset\": \"SciERC\", \"configs\": {\"t07\": {\"one_minus_degen\": 0.777, \"uniform_delta\": 1.81, \"vc_delta\": 1.17, \"pareto\": \"uniform only\"}, \"t08\": {\"one_minus_degen\": 0.819, \"uniform_delta\": 1.25, \"vc_delta\": 1.68, \"pareto\": \"VC only\"}, \"mix_07_10\": {\"one_minus_degen\": 0.83, \"uniform_delta\": 1.43, \"vc_delta\": 1.67, \"pareto\": \"both\"}, \"t10\": {\"one_minus_degen\": 0.877, \"uniform_delta\": 0.75, \"vc_delta\": 1.21, \"pareto\": \"both (highest diversity)\"}, \"mix_08_10\": {\"one_minus_degen\": 0.789, \"uniform_delta\": -0.17, \"vc_delta\": 0.47, \"pareto\": \"dominated\"}}, \"vc_slope_reduction\": \"~50% flatter than uniform\", \"key_insight\": \"well-separated T mixing dual Pareto optimal; close T mixing dominated\"}, \"conclusion\": \"success\", \"notes\": \"A4 Pareto diversity-quality analysis on SciERC. Mix T=0.7+T=1.0 is dual-Pareto optimal (uniform +1.43pp, VC +1.67pp). VC construction flattens trade-off slope ~50% vs uniform — increasing diversity costs less quality. Mix T=0.8+T=1.0 is dominated (close T → higher degeneracy, no construction gain). Confirms DGEC heterogeneous-T finding: ΔT matters, ΔT=0.3 beneficial, ΔT=0.2 harmful. Pareto plot artifact registered.\"}, \"exp_adaptive_sampling_budget\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T09:29:22.761Z\", \"updated_at\": \"2026-05-20T09:29:41.158Z\", \"hypothesis\": \"Confidence-aware adaptive sampling budget allocation (fewer samples for high-confidence instances, full N=8 for low-confidence) can recover nearly all SC F1 gains while saving 40-50% of inference cost, because high-confidence instances already have low diversity and gain nothing from additional samples.\", \"metrics\": {\"model\": \"Qwen3-8B FT\", \"fewnerd\": {\"n_instances\": 37648, \"greedy_f1\": 0.7884, \"uniform_n8_f1\": 0.7819, \"best_adaptive\": \"h1_l8\", \"best_adaptive_f1\": 0.7849, \"best_delta_vs_u8\": \"+0.30pp\", \"sample_savings\": \"43.8%\", \"note\": \"Greedy > U8; adaptive h1/l8 best: greedy for high-conf, N=8 SC for low-conf\"}, \"scierc\": {\"n_instances\": 551, \"greedy_f1\": 0.6592, \"uniform_n8_f1\": 0.6712, \"best_adaptive\": \"top67%_h2_l8\", \"best_adaptive_f1\": 0.6707, \"best_delta_vs_u8\": \"-0.05pp\", \"sample_savings\": \"50.2%\", \"note\": \"U8 > Greedy; top67% h2/l8 saves 50% with negligible loss\"}}, \"conclusion\": \"success\", \"notes\": \"B7 adaptive sampling budget analysis on Qwen3-8B FT. Key findings: (1) FewNERD: greedy already beats uniform N=8 SC (+0.65pp), adaptive h1/l8 is optimal (+0.30pp vs U8, saves 43.8% samples); (2) SciERC: U8 beats greedy (+1.20pp), top67% h2/l8 saves 50% with only -0.05pp loss. Practical implication: confidence-gated sampling can halve inference cost. Artifacts: vc_8b_qwen3_ft_results, sj_8b_qwen3_ft_results (registered by worker).\"}, \"exp_dgec_sj_construction\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:37:58.013Z\", \"updated_at\": \"2026-05-20T09:26:30.567Z\", \"hypothesis\": \"SJ-weighted entity construction serves as control for VC — if SJ (soft entity overlap) works as well as VC (exact match consensus), any stronger QE signal suffices for construction; if VC specifically outperforms SJ, exact-match consensus has a unique advantage over soft similarity for entity-level selection.\", \"metrics\": {\"total_configs\": 26, \"significant_positive\": 1, \"significant_negative\": 15, \"not_significant\": 10, \"best_config\": \"scierc/72b/zs +2.0pp p=0.001\", \"worst_config\": \"fewnerd/8b_qwen3/ft mean -1.48pp all seeds p=1.0\", \"qwen3_8b_ft_supplement\": {\"configs\": 9, \"sig+\": 0, \"sig-\": 6, \"ns\": 3, \"fewnerd_mean_delta\": -1.48, \"scierc_mean_delta\": -0.4, \"conll_mean_delta\": -0.5, \"note\": \"SJ fully negative on Qwen3-8B FT — consistent with Qwen2.5-7B FT pattern\"}, \"m030_all_passed\": true}, \"notes\": \"COMPLETE (26 configs). SJ-weighted construction: 1 sig+ / 15 sig- / 10 ns. Qwen3-8B FT supplement (9 configs): 0+/6-/3ns — fully negative, consistent with 7B FT pattern. FewNERD -1.48pp mean (all seeds p=1.0). Definitively answers control question: NOT any stronger QE signal works for construction. SJ introduces noise at entity level. Only exception: SciERC 72B ZS (lowest precision, lowest degeneracy). Closed per D170/D171.\", \"conclusion\": \"negative\"}, \"exp_dgec_vc_construction\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:37:55.968Z\", \"updated_at\": \"2026-05-20T09:26:29.776Z\", \"hypothesis\": \"VC-weighted entity construction outperforms greedy and LP-weighted construction across configs because Vote Count is a more direct quality estimator for structured outputs — it measures exact-match consensus without relying on model-internal log probabilities. Especially effective in high-degeneracy regimes where LP compression makes LP-weighting uninformative.\", \"metrics\": {\"total_configs\": 28, \"significant_positive\": 9, \"significant_negative\": 10, \"not_significant\": 9, \"by_dataset\": {\"fewnerd\": {\"configs\": 11, \"sig+\": 5, \"sig-\": 5, \"ns\": 1, \"mean_delta_pp\": -0.12}, \"wnut17\": {\"configs\": 3, \"sig+\": 2, \"sig-\": 0, \"ns\": 1, \"mean_delta_pp\": 0.92}, \"scierc\": {\"configs\": 7, \"sig+\": 2, \"sig-\": 0, \"ns\": 5, \"mean_delta_pp\": 0.62}, \"conll\": {\"configs\": 7, \"sig+\": 0, \"sig-\": 5, \"ns\": 2, \"mean_delta_pp\": -0.33}}, \"qwen3_8b_ft_supplement\": {\"configs\": 9, \"sig+\": 3, \"sig-\": 3, \"ns\": 3, \"best\": \"SciERC s42 +1.40pp p=0.017\", \"worst\": \"CoNLL s456 -0.54pp p=0.998\", \"note\": \"VC inconsistent on LP-success configs; seed-dependent on FewNERD; CoNLL all negative due to high degeneracy\"}, \"m030_all_passed\": true}, \"notes\": \"COMPLETE (28 configs). VC-weighted construction: 9 sig+ / 10 sig- / 9 ns. Qwen3-8B FT supplement (9 configs): 3+/3-/3ns — VC inconsistent even on LP-success configs. SciERC s42 best (+1.40pp) but cross-seed unstable. CoNLL all negative (high degeneracy). WNUT17/SciERC lean positive but not robust. Key answer: VC does NOT reliably improve where LP already works — seed-dependent, dataset-dependent. DGEC unified method goal (70-80% configs) unreachable at 32% (9/28). Closed per D170/D171.\", \"conclusion\": \"negative\"}, \"exp_dgec_heterogeneous_t\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:37:59.963Z\", \"updated_at\": \"2026-05-20T08:49:58.009Z\", \"hypothesis\": \"Mixing samples from T=0.7 and T=1.0 significantly reduces degeneracy compared to single-T sampling (by breaking temperature-induced mode collapse), enabling entity construction to achieve significant ΔF1 improvement even in configs where single-T construction was n.s. due to high degeneracy.\", \"metrics\": {\"dataset\": \"SciERC\", \"n_instances\": 529, \"t07_degen\": 0.2231, \"t10_degen\": 0.1235, \"mixed_degen\": 0.1701, \"mixed_uniform_f1\": 0.6584, \"mixed_vc_f1\": 0.6609, \"cross_pool_uniform_delta\": \"+0.006 (1/3 seeds sig)\", \"cross_pool_vc_delta\": \"+0.004 (1/3 seeds sig)\", \"t08_t10_result\": \"harmful (degen increased)\", \"conclusion_preliminary\": \"partially_supported\"}, \"notes\": \"Hypothesis partially supported. T=0.7+T=1.0 mixed pool reduces degen (22.3%→17.0%) and improves construction (VC 3/3 seeds sig vs greedy), but cross-pool comparison (mixed vs T=1.0 alone) only 1/3 seeds significant. T gap matters: ΔT=0.2 (T=0.8+T=1.0) harmful, ΔT=0.3 (T=0.7+T=1.0) beneficial. VC weighting confirmed cross-T compatible. Awaiting Director conclusion classification.\"}, \"exp_qwen25_7b_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:41:43.121Z\", \"updated_at\": \"2026-05-20T05:45:54.613Z\", \"hypothesis\": \"Qwen2.5-7B QLoRA fine-tuned on FewNERD will produce structurally diverse samples enabling self-consistency-based entity extraction with meaningful LP-weighted consensus signals, comparable to the 14B model but with lower compute cost.\", \"spec\": {\"server\": \"autodl-5090-c\", \"gpu_ids\": [\"cuda:2\", \"cuda:3\"], \"command\": \"nohup bash run_fewnerd_qwen25_7b_pipeline.sh > logs/pipeline_qwen25_7b_fewnerd.log 2>&1 &\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/llmfactory_train.json\", \"data_count\": 131767, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-fewnerd-qlora-s42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/pipeline_qwen25_7b_fewnerd.log\", \"training_config\": \"train_config_qwen25_7b_fewnerd_s42.yaml\", \"export_config\": \"export_config_qwen25_7b_fewnerd.yaml\", \"pipeline_script\": \"run_fewnerd_qwen25_7b_pipeline.sh\", \"method\": \"QLoRA 4-bit nf4, rank=32, alpha=64, 5 epochs, lr=2e-4, effective_batch=32\", \"pipeline_phases\": \"train -> export/merge -> 3-seed N=8 inference (42/123/456) -> signal analysis -> entity construction\"}, \"notes\": \"2026-05-19 11:36 UTC: step 138/20590 (0.7%), ~2.34s/it, ETA ~13.3h. Pipeline PID 71837, llamafactory PID 71844. cuda:2,3 98-100% util. Cron registered on pipeline PID.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2,cuda:3\", \"metrics\": {\"3seed_mean\": {\"lp_rho\": 0.346, \"lp_rho_std\": 0.021, \"sj_rho\": 0.388, \"sj_rho_std\": 0.029, \"vc_rho\": 0.404, \"vc_rho_std\": 0.01, \"degen_pct\": 31.7, \"degen_std\": 0.9, \"greedy_f1\": 0.784, \"greedy_f1_std\": 0.001, \"oracle_f1\": 0.876, \"oracle_f1_std\": 0.003, \"construction_lp_delta_pp\": -0.11, \"construction_lp_delta_std\": 0.25}, \"per_seed\": {\"seed42\": {\"lp_rho\": 0.3221, \"sj_rho\": 0.3554, \"vc_rho\": 0.393, \"degen_pct\": 31.1, \"greedy_f1\": 0.7851, \"oracle_f1\": 0.8718, \"construction_lp_delta_pp\": -0.4, \"bootstrap_p\": 1, \"bootstrap_ci\": [-0.53, -0.26], \"cohens_d\": -0.0319}, \"seed123\": {\"lp_rho\": 0.3538, \"sj_rho\": 0.3979, \"vc_rho\": 0.4067, \"degen_pct\": 32.8, \"greedy_f1\": 0.785, \"oracle_f1\": 0.8777, \"construction_lp_delta_pp\": -0.03, \"bootstrap_p\": 0.651}, \"seed456\": {\"lp_rho\": 0.3629, \"sj_rho\": 0.4105, \"vc_rho\": 0.4118, \"degen_pct\": 31.3, \"greedy_f1\": 0.7825, \"oracle_f1\": 0.8771, \"construction_lp_delta_pp\": 0.09, \"bootstrap_p\": 0.168}}, \"construction_significant\": false}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T05:45:54.613Z\"}, \"exp_qwen25_72b_fewshot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T15:59:44.340Z\", \"updated_at\": \"2026-05-20T00:54:59.032Z\", \"hypothesis\": \"Few-shot prompting improves base NER F1 and LP signal quality, enabling LP-weighted construction to outperform greedy selection via dual-gating (sufficient LP ρ + low degeneracy).\", \"parent\": \"exp_qwen25_72b_zeroshot\", \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"started_at\": \"2026-05-19T16:22:20.071Z\", \"finished_at\": \"2026-05-20T00:47:36.445Z\", \"training_hours\": 8.42}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0,1,2,3 python code/fewshot_inference_72b.py --datasets scierc conll2003 fewnerd --output-dir output/72b_fewshot --seed 42\\\"\", \"server\": \"autodl-5090-b\", \"gpu\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"pid\": 131293, \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen25_72b_fewshot.log\", \"submitted_at\": \"2026-05-19T16:25:57.711Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/{scierc,conll2003,fewnerd}\", \"data_count\": 41652, \"model_name\": \"Qwen2.5-72B-Instruct-AWQ\", \"seed\": 42, \"gpu_ids\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"checkpoint_source\": \"Qwen2.5-72B-Instruct-AWQ (base model, no fine-tuning)\", \"eval_data\": \"SciERC + CoNLL-2003 + FewNERD test sets\", \"wall_clock_seconds\": 30541.3, \"gpu_hours\": 33.93}, \"metrics\": {\"scierc\": {\"lp_rho\": 0.06, \"sj_rho\": 0.293, \"fk_rho\": 0.301, \"vc_rho\": 0.258, \"em_rho\": 0.205, \"degen_pct\": 16.6, \"greedy_f1\": 0.461, \"oracle_f1\": 0.604, \"construction_f1\": 0.461, \"construction_delta_pp\": -0.08, \"bootstrap_p\": 0.544}, \"conll\": {\"lp_rho\": 0.106, \"sj_rho\": 0.442, \"fk_rho\": 0.451, \"vc_rho\": 0.426, \"em_rho\": 0.403, \"degen_pct\": 70, \"greedy_f1\": 0.745, \"oracle_f1\": 0.796, \"construction_f1\": 0.745, \"construction_delta_pp\": 0.03, \"bootstrap_p\": 0.417}, \"fewnerd\": {\"lp_rho\": 0.161, \"sj_rho\": 0.345, \"fk_rho\": 0.327, \"vc_rho\": 0.41, \"em_rho\": 0.302, \"degen_pct\": 45.2, \"greedy_f1\": 0.619, \"oracle_f1\": 0.702, \"construction_f1\": 0.619, \"construction_delta_pp\": 0.02, \"bootstrap_p\": 0.401}}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T00:47:43.131229+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"output/72b_fewshot/ + output/72b_fewshot_signals/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen25_72b_fewshot.log\", \"completed_at\": \"2026-05-20T00:54:59.032Z\"}, \"exp_qwen25_72b_zeroshot\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-19T06:19:28.597Z\", \"updated_at\": \"2026-05-19T16:23:10.481Z\", \"hypothesis\": \"A larger zero-shot model (72B) will show higher greedy F1 and wider oracle-greedy gap than fine-tuned smaller models, because increased capacity enables more diverse valid extractions per stochastic sample, making self-consistency signals (SJ, FK, VC, EM) more informative for quality estimation.\", \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"started_at\": \"2026-05-19T06:47:42.658Z\", \"finished_at\": \"2026-05-19T14:14:58.577Z\", \"training_hours\": 7.45}, \"notes\": \"2026-05-19 12:47 UTC: RECOVERED from false-positive startup recovery failure. 289848/301184 prompts (96.2%). SciERC ✅ (551) CoNLL ✅ (3453) FewNERD ~96%. ETA ~10-15min. PID 59040, 4×5090 100% util. Cron registered.\", \"failure_reason\": \"FALSE POSITIVE — cron误判。实验实际成功完成（3个数据集全部处理完毕）。\", \"completed_at\": \"2026-05-19T12:44:26.198Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"2026-05-19 11:36 UTC: 69.8% complete (210352/301184 prompts). SciERC ✅ CoNLL ✅ FewNERD ~66%. ETA ~1h15m. vLLM PID 59040, 4×5090 100% util.\"}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T14:15:08.634709+00:00\"}]}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0,1,2,3 python code/zeroshot_inference_72b.py --datasets scierc conll2003 fewnerd --output-dir output/72b_zeroshot --seed 42\", \"server\": \"autodl-5090-b\", \"data_path\": \"data/{scierc,conll2003,fewnerd}\", \"data_count\": 41630, \"model_name\": \"Qwen2.5-72B-Instruct-AWQ\", \"seed\": 42, \"gpu_ids\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"pid\": 59040}, \"conclusion\": \"negative\", \"metrics\": {\"scierc\": {\"greedy_f1\": 0.3993, \"lp_rho\": 0.081, \"vc_rho\": 0.277, \"sj_rho\": 0.217, \"degen_rate\": 0.21, \"construction_lp_weighted_f1\": 0.4146, \"construction_lp_delta_pp\": 1.53, \"construction_uniform_f1\": 0.3941, \"construction_uniform_delta_pp\": -0.52, \"lp_selection_f1\": 0.3984, \"majority_vote_f1\": 0.4132, \"oracle_f1\": 0.5489, \"bootstrap_p\": 0.0082, \"bootstrap_ci_lower\": 0.0025, \"bootstrap_ci_upper\": 0.0282, \"cohens_d\": 0.1027, \"n_instances\": 529, \"non_degen_delta_pp\": 1.65, \"non_degen_p\": 0.0069}, \"conll2003\": {\"greedy_f1\": 0.712, \"lp_rho\": -0.002, \"vc_rho\": 0.297, \"sj_rho\": 0.304, \"degen_rate\": 0.677, \"construction_lp_weighted_f1\": 0.7083, \"construction_lp_delta_pp\": -0.37, \"construction_uniform_f1\": 0.7028, \"construction_uniform_delta_pp\": -0.92, \"lp_selection_f1\": 0.708, \"majority_vote_f1\": 0.7034, \"oracle_f1\": 0.7651}, \"fewnerd\": {\"greedy_f1\": 0.6281, \"lp_rho\": 0.119, \"vc_rho\": 0.416, \"sj_rho\": 0.345, \"degen_rate\": 0.462, \"construction_lp_weighted_f1\": 0.6261, \"construction_lp_delta_pp\": -0.2, \"construction_uniform_f1\": 0.6112, \"construction_uniform_delta_pp\": -1.7, \"lp_selection_f1\": 0.6241, \"lp_selection_delta_pp\": -0.4, \"majority_vote_f1\": 0.6262, \"oracle_f1\": 0.7072}}}, \"exp_wnut17_qwen25_7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:19:33.960Z\", \"updated_at\": \"2026-05-19T11:49:07.313Z\", \"hypothesis\": \"The correlation-selection gap extends to noisy social media NER (WNUT-17). Unlike formal-domain datasets (SciERC/CoNLL/FewNERD), WNUT-17 has higher surface-level noise which may affect structural signal reliability differently. This tests domain generalization of the diagnostic framework.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2,cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2,cuda:3\", \"started_at\": \"2026-05-19T06:47:45.220Z\"}, \"spec\": {\"server\": \"autodl-5090-c\", \"gpu_ids\": [\"cuda:2\", \"cuda:3\"], \"command\": \"bash wait_and_train.sh (screen: exp_wnut17_7b)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/wnut17/llmfactory_train.json\", \"data_count\": 3404, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"training_config\": \"train_config_qwen25_7b_wnut17_s42.yaml\", \"method\": \"QLoRA 4-bit (bnb nf4), rank=32, alpha=64, all targets\", \"gpus\": \"cuda:2,3 (2x5090)\", \"epochs\": 5, \"effective_batch_size\": 32, \"pipeline\": \"train → export → 3-seed inference (N=8, T=1.0) → signal analysis → entity construction\", \"checkpoint_source\": \"self-trained on WNUT-17\", \"eval_data\": \"WNUT-17 test set\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-wnut17-qlora-s42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp_wnut17_7b_pipeline.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"seed42\": {\"greedy_f1\": 0.4524, \"construction_f1\": 0.4439, \"construction_delta_pp\": -0.84, \"construction_p\": 0.95}, \"seed123\": {\"greedy_f1\": 0.4518, \"construction_f1\": 0.4579, \"construction_delta_pp\": 0.61, \"construction_p\": 0.08}, \"seed456\": {\"greedy_f1\": 0.4526, \"construction_f1\": 0.4583, \"construction_delta_pp\": 0.57, \"construction_p\": 0.12}, \"oracle_headroom_pp\": \"6.3-9.2\"}, \"completed_at\": \"2026-05-19T11:22:56.623Z\"}, \"exp_llama_fewnerd_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:18:49.938Z\", \"updated_at\": \"2026-05-19T03:15:04.486Z\", \"hypothesis\": \"LLaMA-3.1-8B fine-tuned on FewNERD shows the same structured self-consistency phenomena (degeneracy, LP-F1 alignment, signal ranking) as Qwen models, providing cross-model generalization evidence. 3-seed inference (42/123/456) for statistical robustness.\", \"parent\": \"exp_llama_fewnerd_lora\", \"spec\": {\"command\": \"bash code/run_llama_fewnerd_inference.sh\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/\", \"data_count\": 37648, \"model_name\": \"LLaMA-3.1-8B-FewNERD-LoRA-merged\", \"seed\": \"42,123,456\", \"checkpoint_source\": \"exp_llama_fewnerd_lora\", \"eval_data\": \"FewNERD test set\", \"checkpoint_path\": \"checkpoints/llama3.1-8b-fewnerd-merged/\", \"log_path\": \"logs/llama_fewnerd_inference.log\"}, \"conclusion\": \"success\", \"metrics\": {\"3seed_mean\": {\"greedy_f1\": 0.7842, \"oracle_f1\": 0.8843, \"headroom_pp\": 10.01, \"degeneracy_pct\": 23.36, \"lp_delta_pp\": 0.36, \"dgs_delta_pp\": -0.35}, \"seed_42\": {\"greedy_f1\": 0.7841, \"oracle_f1\": 0.8854, \"degen\": 27.32}, \"seed_123\": {\"greedy_f1\": 0.784, \"oracle_f1\": 0.8839, \"degen\": 24.63}, \"seed_456\": {\"greedy_f1\": 0.7844, \"oracle_f1\": 0.8835, \"degen\": 18.13}, \"signal_ranking\": \"LP (+0.36pp) > SJ (-0.52) > FK (-0.53) > EM (-1.02) > VC (-2.39)\", \"lp_only_positive\": true, \"n_instances_gold_filtered\": 32565}, \"completed_at\": \"2026-05-19T03:15:04.486Z\"}, \"exp_entity_construction\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:00:12.074Z\", \"updated_at\": \"2026-05-19T02:40:17.571Z\", \"hypothesis\": \"Entity-level majority vote construction is the correct self-consistency analogy for structured IE: instead of selecting the best instance-level output, assemble a better output from entity-level consensus across N samples. Construction should outperform both greedy and best-of-N selection.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/entity_construction_fair.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/*/samples_*.json\", \"data_count\": 3, \"model_name\": \"analysis_cpu\", \"seed\": 42, \"checkpoint_path\": \"output/entity_construction_fair/\", \"log_path\": \"output/entity_construction_fair/\"}, \"completed_at\": \"2026-05-19T02:15:19.616Z\", \"metrics\": {\"n16_fair_cv\": {\"scierc_ner\": {\"cv_uniform_delta\": \"+1.35pp\", \"p_value\": 0.018, \"significant\": true}, \"conll_ner\": {\"cv_uniform_delta\": \"+0.10pp\", \"p_value\": 0.303, \"significant\": false}, \"fewnerd_ner\": {\"cv_uniform_delta\": \"+1.32pp\", \"p_value\": 0, \"significant\": true}, \"scierc_re\": {\"cv_uniform_delta\": \"+1.69pp\", \"p_value\": 0.049, \"significant\": true}}, \"n8_fair_cv\": {\"scierc_ner\": {\"uniform_confirm\": \"+1.54pp (p=0.023, sig)\", \"lp_weighted_confirm\": \"+1.67pp (p=0.004, sig)\", \"cv_uniform\": \"+1.12pp (p=0.057, borderline)\"}, \"conll_ner\": {\"cv_uniform\": \"-0.39pp (p=0.963, not sig)\"}, \"fewnerd_ner\": {\"lp_weighted_cv\": \"+0.88pp (p=0.000, sig)\", \"uniform_cv\": \"+0.32pp (p=0.003, sig)\"}}, \"adaptive_combination\": \"INVALIDATED - gold label leakage confirmed\", \"note\": \"5-fold CV, bootstrap B=10000, paired one-sided\"}}, \"exp_lp_alignment_gating\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:00:16.520Z\", \"updated_at\": \"2026-05-19T02:15:48.197Z\", \"hypothesis\": \"Within-instance LP-F1 alignment score (adjusted by valid_ratio for degeneracy) can automatically gate whether LP selection should be applied to a dataset. A small probe sample (50-100 instances) suffices for a stable gating decision.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/lp_alignment_gated_selection.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/*/samples_*.json\", \"data_count\": 3, \"model_name\": \"analysis_cpu\", \"seed\": 42, \"checkpoint_path\": \"output/prescriptive_analysis/\", \"log_path\": \"output/prescriptive_analysis/\"}, \"completed_at\": \"2026-05-19T02:15:23.716Z\", \"metrics\": {\"adjusted_score\": \"mean_rho * valid_ratio\", \"threshold\": 0.3, \"accuracy\": \"3/3 datasets correct\", \"robust_range\": \"0.2-0.4\"}}, \"exp_selective_prediction\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:00:13.989Z\", \"updated_at\": \"2026-05-19T02:15:46.588Z\", \"hypothesis\": \"QE signals (especially voting_confidence) can drive practical selective prediction: filtering out low-confidence instances yields significant F1 improvement on retained instances, enabling human-AI collaboration for structured IE.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/selective_prediction.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/*/samples_*.json\", \"data_count\": 3, \"model_name\": \"analysis_cpu\", \"seed\": 42, \"checkpoint_path\": \"output/prescriptive_analysis/\", \"log_path\": \"output/prescriptive_analysis/\"}, \"completed_at\": \"2026-05-19T02:15:21.704Z\", \"metrics\": {\"vc_best_signal\": true, \"f1_at_80pct_coverage\": {\"scierc\": \"+5.0pp\", \"conll\": \"+8.4pp\", \"fewnerd\": \"+6.2pp\"}, \"precision_coverage_curves\": \"output/prescriptive_analysis/fig_selective_prediction.pdf\"}}, \"exp_llama_fewnerd_lora\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T13:20:55.859Z\", \"updated_at\": \"2026-05-19T01:08:20.832Z\", \"hypothesis\": \"LLaMA-based model with LoRA fine-tuning on Few-NERD can provide a second model family (beyond Qwen) for cross-model generalization evidence of structured self-consistency phenomena in NER\", \"spec\": {\"command\": \"llamafactory-cli train train_config_llama_fewnerd.yaml\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": 137865, \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd\", \"data_count\": -1, \"model_name\": \"LLaMA-Few-NERD-LoRA\", \"seed\": 42, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/llama_fewnerd_train.log\", \"run_script\": \"run_llama_fewnerd_train_single_gpu.sh\", \"tmux_session\": \"llama_fewnerd\", \"note\": \"Retroactively registered - data_count unknown, seed assumed 42\"}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/llama3.1-8b-fewnerd-lora\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/llama_fewnerd_train.log\", \"conclusion\": \"success\", \"metrics\": {\"epoch\": 3, \"train_loss\": 0.0516, \"eval_loss\": 0.0323, \"train_runtime_hours\": 15.35, \"total_steps\": 24708, \"final_checkpoint\": \"checkpoint-24708\", \"adapter_size_mb\": 320}, \"completed_at\": \"2026-05-19T01:08:20.832Z\"}, \"hidden_state_probe_conll_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:57:45.711Z\", \"updated_at\": \"2026-05-19T00:30:18.272Z\", \"conclusion\": \"killed\", \"notes\": \"Not in D154 Dual Contribution framing\", \"completed_at\": \"2026-05-19T00:30:18.272Z\"}, \"hidden_state_probe_conll_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:35:05.317Z\", \"updated_at\": \"2026-05-19T00:30:16.471Z\", \"conclusion\": \"killed\", \"notes\": \"Not in D154 Dual Contribution framing\", \"completed_at\": \"2026-05-19T00:30:16.471Z\"}, \"exp_031_fewnerd_t12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:04:12.040Z\", \"updated_at\": \"2026-05-19T00:30:14.652Z\", \"hypothesis\": \"FewNERD T=1.2 temperature ablation: test if higher temperature reduces degeneracy on FewNERD as observed on SciERC\", \"conclusion\": \"killed\", \"failure_reason\": \"数据不可用于论文：测试集(37648 vs T=1.0的5000)、N(8 vs 16)、分析管道(MVP pilot vs 5-signal)三重不一致。Director决定不重跑(DDL约束+非核心claim)。\", \"notes\": \"T=1.2 ablation not in paper scope, SciERC T=1.2 sufficient\", \"completed_at\": \"2026-05-19T00:30:14.652Z\"}, \"exp_030_conll_t12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:24:47.839Z\", \"updated_at\": \"2026-05-19T00:30:12.698Z\", \"hypothesis\": \"CoNLL T=1.2 temperature ablation: test if higher temperature reduces degeneracy on CoNLL as observed on SciERC\", \"conclusion\": \"killed\", \"failure_reason\": \"数据不可用于论文：N不一致(N=8 vs T=1.0基准的N=16)。Director决定不重跑——SciERC T消融(T=0.5/0.8/1.0/1.2, 551inst, N=8)已够用，论文温度消融用SciERC单数据集。\", \"notes\": \"T=1.2 ablation not in paper scope, SciERC T=1.2 sufficient\", \"completed_at\": \"2026-05-19T00:30:12.699Z\"}, \"mbr_pilot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:56:06.462Z\", \"updated_at\": \"2026-05-19T00:29:39.285Z\", \"conclusion\": \"killed\", \"notes\": \"MBR tested negative as one of 6 methods, stale entry\", \"completed_at\": \"2026-05-19T00:29:39.285Z\"}, \"dgs_pilot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:56:04.572Z\", \"updated_at\": \"2026-05-19T00:29:37.275Z\", \"hypothesis\": \"Degeneracy-Gated Selection (DGS) validates Two-Condition Theory: using degeneracy rate as gating mechanism to switch between greedy (degenerate) and LP selection (non-degenerate), the improvement direction should follow a monotonic gradient — low degeneracy yields positive delta, high degeneracy yields negative delta.\", \"conclusion\": \"killed\", \"notes\": \"D154: DGS demoted to explored heuristic, cross-model direction contradiction (D152)\", \"completed_at\": \"2026-05-19T00:29:37.275Z\"}, \"exp_fewnerd_s789_n8\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:17:34.011Z\", \"updated_at\": \"2026-05-18T23:18:28.125Z\", \"hypothesis\": \"FewNERD seed789 (4th seed) for statistical CI strengthening: 4-seed protocol provides tighter confidence intervals on LP selection gain and DGS effectiveness in low-degeneracy regime.\", \"parent\": \"exp_029a\", \"spec\": {\"command\": \"python code/analyze_fewnerd_s789.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/samples.jsonl\", \"data_count\": 37648, \"model_name\": \"Qwen3-8B (ft_002_v2)\", \"seed\": 789, \"checkpoint_source\": \"exp_021 shards\", \"eval_data\": \"FewNERD test (37648 instances, 32565 gold-filtered)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T23:18:17.902Z\", \"metrics\": {\"greedy_f1\": 0.7478, \"oracle_f1\": 0.8714, \"headroom_pp\": 12.37, \"degen_rate\": 0.1177, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 37648, \"n_valid\": 32565, \"lp_sel_f1\": 0.7614, \"lp_delta_pp\": 1.36, \"lp_rho_global\": 0.1788, \"lp_rho_cond\": 0.176, \"dgs_f1\": 0.7621, \"dgs_delta_pp\": 1.43, \"dgs_vs_lp_pp\": 0.07, \"best_signal\": \"LP\", \"four_seed_mean_greedy\": 0.7481, \"four_seed_mean_lp_delta_pp\": 1.38, \"four_seed_lp_delta_ci95\": [1.32, 1.44]}}, \"exp_026_t12_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:43.694Z\", \"updated_at\": \"2026-05-18T22:07:24.547Z\", \"hypothesis\": \"Temperature ablation (T=1.2, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 1.2\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:05.941Z\", \"metrics\": {\"ner_greedy_f1\": 0.6637, \"ner_oracle_f1\": 0.7821, \"rho_sj_ner\": 0.3995, \"sample_f1_pct_zero\": 14.08, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t12_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:42.754Z\", \"updated_at\": \"2026-05-18T22:07:23.135Z\", \"hypothesis\": \"Temperature ablation (T=1.2, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 1.2\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:04.119Z\", \"metrics\": {\"ner_greedy_f1\": 0.6595, \"ner_oracle_f1\": 0.7895, \"rho_sj_ner\": 0.359, \"sample_f1_pct_zero\": 13.99, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t10_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:41.840Z\", \"updated_at\": \"2026-05-18T22:07:21.767Z\", \"hypothesis\": \"Temperature ablation (T=1.0, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:02.272Z\", \"metrics\": {\"ner_greedy_f1\": 0.6621, \"ner_oracle_f1\": 0.7754, \"rho_sj_ner\": 0.3921, \"sample_f1_pct_zero\": 12.97, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t10_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:40.599Z\", \"updated_at\": \"2026-05-18T22:07:20.459Z\", \"hypothesis\": \"Temperature ablation (T=1.0, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:00.430Z\", \"metrics\": {\"ner_greedy_f1\": 0.6633, \"ner_oracle_f1\": 0.7777, \"rho_sj_ner\": 0.3809, \"sample_f1_pct_zero\": 12.59, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t10_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:39.473Z\", \"updated_at\": \"2026-05-18T22:07:19.035Z\", \"hypothesis\": \"Temperature ablation (T=1.0, seed=42) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 42 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed42.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:58.573Z\", \"metrics\": {\"ner_greedy_f1\": 0.6617, \"ner_oracle_f1\": 0.7798, \"rho_sj_ner\": 0.3598, \"sample_f1_pct_zero\": 12.9, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t08_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:38.605Z\", \"updated_at\": \"2026-05-18T22:07:17.604Z\", \"hypothesis\": \"Temperature ablation (T=0.8, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 0.8\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:56.681Z\", \"metrics\": {\"ner_greedy_f1\": 0.6641, \"ner_oracle_f1\": 0.7694, \"rho_sj_ner\": 0.3771, \"sample_f1_pct_zero\": 11.79, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t08_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:37.454Z\", \"updated_at\": \"2026-05-18T22:07:16.089Z\", \"hypothesis\": \"Temperature ablation (T=0.8, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 0.8\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:54.734Z\", \"metrics\": {\"ner_greedy_f1\": 0.6607, \"ner_oracle_f1\": 0.7714, \"rho_sj_ner\": 0.3893, \"sample_f1_pct_zero\": 11.22, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t05_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:36.536Z\", \"updated_at\": \"2026-05-18T22:07:14.675Z\", \"hypothesis\": \"Temperature ablation (T=0.5, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 0.5\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:52.749Z\", \"metrics\": {\"ner_greedy_f1\": 0.6639, \"ner_oracle_f1\": 0.7437, \"rho_sj_ner\": 0.3279, \"sample_f1_pct_zero\": 10.28, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t05_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:35.201Z\", \"updated_at\": \"2026-05-18T22:07:13.198Z\", \"hypothesis\": \"Temperature ablation (T=0.5, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 0.5\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:50.703Z\", \"metrics\": {\"ner_greedy_f1\": 0.6611, \"ner_oracle_f1\": 0.7444, \"rho_sj_ner\": 0.3133, \"sample_f1_pct_zero\": 10.09, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_029b\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T23:32:18.543Z\", \"updated_at\": \"2026-05-18T22:05:45.856Z\", \"hypothesis\": \"Training convergence modulates degeneracy across datasets. SciERC 10-epoch training should produce higher degeneracy than 5-epoch baseline (17.8%), confirming monotonic epoch-degeneracy relationship across datasets.\", \"parent\": \"ft_002_v2\", \"failure_reason\": \"OOM on cuda:1 due to residual vLLM process (PID 416808) occupying 30.2GB VRAM\", \"reproduce\": {\"finished_at\": \"2026-05-18T02:05:15.948Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T00:55:29.806594+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T01:58:43.646574+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T02:05:20.480884+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"completed_at\": \"2026-05-18T00:56:47.625Z\", \"spec\": {\"pid\": \"441471\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"command\": \"FORCE_TORCHRUN=0 CUDA_VISIBLE_DEVICES=1 llamafactory-cli train train_config_scierc_10ep.yaml\", \"data_path\": \"scierc_uie_train\", \"data_count\": 1861, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen3-8B\", \"eval_data\": \"scierc_uie_test\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-10epoch-lora/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_029b.log\"}, \"metrics\": {\"degen_rate\": 0.478, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"conclusion\": \"success\"}, \"exp_029a\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T23:32:17.191Z\", \"updated_at\": \"2026-05-18T22:05:44.959Z\", \"hypothesis\": \"Training convergence modulates degeneracy across datasets. SciERC 3-epoch training should produce lower degeneracy than 5-epoch baseline (17.8%), confirming epoch confound is not Few-NERD-specific.\", \"parent\": \"ft_002_v2\", \"spec\": {\"command\": \"FORCE_TORCHRUN=0 CUDA_VISIBLE_DEVICES=0 bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_scierc_3ep.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 436761, \"data_path\": \"data/scierc_uie_train\", \"data_count\": 1861, \"model_name\": \"Qwen3-8B LoRA rank=32\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-3epoch-lora\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp_029a_inference.log\", \"checkpoint_source\": \"Qwen/Qwen3-8B\", \"eval_data\": \"data/scierc_uie_dev\"}, \"reproduce\": {\"finished_at\": \"2026-05-18T00:55:16.392Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T00:55:20.617085+00:00\"}]}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T01:00:18.242Z\", \"metrics\": {\"degen_rate\": 0.064, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_021_fewnerd_n8_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:17.992Z\", \"updated_at\": \"2026-05-18T22:04:50.774Z\", \"hypothesis\": \"Multi-seed replication (seed=456) of Qwen3-8B FewNERD N=8 SCS inference to validate structural consistency signal on fine-grained NER dataset.\", \"spec\": {\"command\": \"python scs_inference.py --dataset fewnerd --seed 456 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd\", \"data_count\": 37648, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed456_run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:35.573Z\", \"metrics\": {\"degen_rate\": 0.1212, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 37648, \"n_valid\": 32565, \"n_gold_empty\": 5083, \"ner_greedy_f1\": 0.7888, \"ner_oracle_f1\": 0.881, \"rho_fk_ner\": 0.1632, \"rho_sj_ner\": 0.313, \"sample_f1_pct_zero\": 19.32}}, \"exp_021_fewnerd_n8_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:16.735Z\", \"updated_at\": \"2026-05-18T22:04:49.470Z\", \"hypothesis\": \"Multi-seed replication (seed=123) of Qwen3-8B FewNERD N=8 SCS inference to validate structural consistency signal on fine-grained NER dataset.\", \"spec\": {\"command\": \"python scs_inference.py --dataset fewnerd --seed 123 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd\", \"data_count\": 37648, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed123_run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:33.731Z\", \"metrics\": {\"degen_rate\": 0.1312, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 37648, \"n_valid\": 32565, \"n_gold_empty\": 5083, \"ner_greedy_f1\": 0.7885, \"ner_oracle_f1\": 0.8892, \"rho_fk_ner\": 0.1602, \"rho_sj_ner\": 0.3083, \"sample_f1_pct_zero\": 20.39}}, \"exp_002_conll_n16_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:15.720Z\", \"updated_at\": \"2026-05-18T22:04:46.954Z\", \"hypothesis\": \"Multi-seed replication (seed=456) of Qwen3-8B CoNLL-2003 N=16 SCS inference to validate structural consistency signal stability across random seeds.\", \"spec\": {\"command\": \"python scs_inference.py --dataset conll2003 --seed 456 --n_samples 16 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:31.934Z\", \"metrics\": {\"degen_rate\": 0.5544, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"ner_greedy_f1\": 0.9074, \"ner_oracle_f1\": 0.9549, \"rho_fk_ner\": 0.4718, \"rho_sj_ner\": 0.4819, \"sample_f1_pct_zero\": 7.02}}, \"exp_002_conll_n16_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:14.343Z\", \"updated_at\": \"2026-05-18T22:04:45.039Z\", \"hypothesis\": \"Multi-seed replication (seed=123) of Qwen3-8B CoNLL-2003 N=16 SCS inference to validate structural consistency signal stability across random seeds.\", \"spec\": {\"command\": \"python scs_inference.py --dataset conll2003 --seed 123 --n_samples 16 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:29.992Z\", \"metrics\": {\"degen_rate\": 0.471, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"ner_greedy_f1\": 0.9068, \"ner_oracle_f1\": 0.9633, \"rho_fk_ner\": 0.4524, \"rho_sj_ner\": 0.4621, \"sample_f1_pct_zero\": 7.54}}, \"exp_017_llama_conll_n16_s456_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:04.572Z\", \"updated_at\": \"2026-05-18T20:50:15.047Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed456.\", \"parent\": \"exp_017_llama_conll_n16_s456\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 456, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_s456_r1024\", \"gpu\": \"cuda:2\", \"pid\": \"175870\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"tmux_session\": \"exp_017_llama_conll_n16_s456_r1024\"}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.8672, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"parse_rate\": 1, \"ner_greedy_f1\": 0.9265, \"ner_oracle_f1\": 0.9499, \"rho_fk_ner\": 0.469, \"rho_sj_ner\": 0.4734, \"rho_vc_ner\": 0.4722, \"rho_em_ner\": 0.4752, \"rho_lp_ner\": 0.3099, \"auroc_fk_ner\": 0.7408, \"auroc_sj_ner\": 0.7428, \"auroc_vc_ner\": 0.7495, \"auroc_em_ner\": 0.7444, \"auroc_lp_ner\": 0.7628, \"auroc_note\": \"median F1=1.0, AUROC uses >=median threshold\", \"rho_note\": \"CORRECTED 2026-05-15: old values (rho_fk=0.8085,rho_sj=0.1895) were inflated/deflated by 697 gold-empty instances. Now uses gold-filtered pipeline (n=2756).\"}, \"checkpoint_path\": \"N/A (inference-only)\", \"log_path\": \"output/exp_017_llama_conll_n16_s456_r1024_run.log\", \"completed_at\": \"2026-05-15T11:45:25.899Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=456 (max_tokens=1024 rerun): cross-model multi-seed validation. Confirms structural>surface ordering is stable across seeds for LLaMA on CoNLL after gold-filtering correction.\"}, \"exp_017_llama_conll_n16_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:01.036Z\", \"updated_at\": \"2026-05-18T20:50:11.906Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed42.\", \"parent\": \"exp_017_llama_conll_n16\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_r1024\", \"gpu\": \"cuda:1\", \"pid\": \"175734\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"tmux_session\": \"exp_017_llama_conll_n16_r1024\"}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.8647, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"parse_rate\": 1, \"ner_greedy_f1\": 0.9265, \"ner_oracle_f1\": 0.9499, \"rho_fk_ner\": 0.4752, \"rho_sj_ner\": 0.4836, \"rho_vc_ner\": 0.4746, \"rho_em_ner\": 0.4818, \"rho_lp_ner\": 0.3136, \"auroc_fk_ner\": 0.7467, \"auroc_sj_ner\": 0.7496, \"auroc_vc_ner\": 0.7529, \"auroc_em_ner\": 0.7508, \"auroc_lp_ner\": 0.7661, \"auroc_note\": \"median F1=1.0, AUROC uses >=median threshold\", \"rho_note\": \"CORRECTED 2026-05-15: old values (rho_fk=0.8095,rho_sj=0.1815) were inflated/deflated by 697 gold-empty instances. Now uses gold-filtered pipeline (n=2756).\"}, \"checkpoint_path\": \"N/A (inference-only)\", \"log_path\": \"output/exp_017_llama_conll_n16_r1024_run.log\", \"completed_at\": \"2026-05-15T11:45:23.213Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=42 (max_tokens=1024 rerun): cross-model baseline on CoNLL. Establishes LLaMA signal rankings after gold-filtering correction (fixes inflated FK ρ from gold-empty instances).\"}, \"exp_018_llama_scierc_seed456_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:12:43.492Z\", \"updated_at\": \"2026-05-18T20:50:04.988Z\", \"spec\": {\"hypothesis\": \"D066 fresh rerun: LLaMA SciERC seed=456 with explicit max_tokens=1024. Replaces exp_007 re-analysis for clean 3-seed comparison.\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed456_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": \"157584\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"finished_at\": \"2026-05-15T06:18:22.307Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T06:18:24.880896+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_018_llama_scierc_seed456_r1024\", \"metrics\": {\"degen_rate\": 0.2741, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"ner_greedy_f1\": 0.6597, \"ner_oracle_f1\": 0.7683, \"ner_oracle_headroom\": 0.1086, \"ner_cond_rho_fk\": 0.1472, \"ner_cond_rho_sj\": 0.2718, \"ner_cond_rho_logprob\": 0.083, \"ner_logprob_auroc_cond\": 0.5485, \"re_greedy_f1\": 0.4338, \"re_oracle_f1\": 0.5834, \"re_oracle_headroom\": 0.1496, \"re_cond_rho_fk\": 0.2107, \"re_cond_rho_sj\": 0.3898, \"re_cond_rho_logprob\": 0.1252, \"re_logprob_auroc_cond\": 0.6119, \"ner_structural_beats_logprob\": true, \"re_structural_beats_logprob\": true}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:21:45.350Z\", \"hypothesis\": \"LLaMA SciERC seed=456 (max_tokens=1024): multi-seed cross-model validation. Complements seed42 for LLaMA 3-seed protocol on SciERC NER+RE signal rankings.\"}, \"exp_018_llama_scierc_seed42_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:09:57.155Z\", \"updated_at\": \"2026-05-18T20:50:00.335Z\", \"spec\": {\"hypothesis\": \"D066 fresh rerun: LLaMA SciERC seed=42 with explicit max_tokens=1024. Replaces exp_007_llama_inference for clean 3-seed comparison.\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed42_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 42, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed42_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed42_r1024.log\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"156809\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed42_r1024.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed42_r1024\\\"\", \"finished_at\": \"2026-05-15T06:15:47.963Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T06:15:50.613872+00:00\"}]}, \"metrics\": {\"degen_rate\": 0.2495, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"ner\": {\"full\": {\"SJ\": {\"rho\": 0.3096, \"tau\": 0.2288, \"auroc\": 0.6683}, \"FK\": {\"rho\": 0.2352, \"tau\": 0.1759, \"auroc\": 0.6069}, \"logprob\": {\"rho\": 0.1503, \"tau\": 0.1087, \"auroc\": 0.5318}, \"EM\": {\"rho\": 0.2587, \"tau\": 0.1966, \"auroc\": 0.7174}, \"voting_conf\": {\"rho\": 0.4053, \"tau\": 0.3042, \"auroc\": 0.6967}}, \"conditional\": {\"SJ\": {\"rho\": 0.2718, \"tau\": null, \"auroc\": 0.6565}, \"FK\": {\"rho\": 0.1472, \"tau\": null, \"auroc\": 0.5866}, \"logprob\": {\"rho\": 0.081, \"tau\": null, \"auroc\": 0.5129}, \"EM\": {\"rho\": 0.3165, \"tau\": null, \"auroc\": 0.7244}, \"voting_conf\": {\"rho\": 0.3078, \"tau\": null, \"auroc\": 0.6714}}, \"greedy_f1\": 0.6607, \"oracle_f1\": 0.7781, \"n_full\": 529, \"n_cond\": 478}, \"re\": {\"full\": {\"SJ\": {\"rho\": 0.2748, \"tau\": 0.2102, \"auroc\": 0.7244}, \"FK\": {\"rho\": 0.3027, \"tau\": 0.2337, \"auroc\": 0.691}, \"logprob\": {\"rho\": 0.3163, \"tau\": 0.233, \"auroc\": 0.6313}, \"EM\": {\"rho\": 0.1681, \"tau\": 0.1275, \"auroc\": 0.7697}, \"voting_conf\": {\"rho\": 0.384, \"tau\": 0.2965, \"auroc\": 0.7337}}, \"conditional\": {\"SJ\": {\"rho\": 0.3461, \"tau\": null, \"auroc\": 0.7233}, \"FK\": {\"rho\": 0.1969, \"tau\": null, \"auroc\": 0.6684}, \"logprob\": {\"rho\": 0.0888, \"tau\": null, \"auroc\": 0.5556}, \"EM\": {\"rho\": 0.4969, \"tau\": null, \"auroc\": 0.819}, \"voting_conf\": {\"rho\": 0.3433, \"tau\": null, \"auroc\": 0.7003}}, \"greedy_f1\": 0.4319, \"oracle_f1\": 0.5775, \"n_full\": 397, \"n_cond\": 251}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:21:47.660Z\", \"hypothesis\": \"LLaMA SciERC seed=42 (max_tokens=1024): cross-model validation on SciERC. Establishes LLaMA NER signal rankings on same dataset as Qwen for direct model-family comparison.\"}, \"exp_002_conll_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:12:16.041Z\", \"updated_at\": \"2026-05-18T20:49:50.398Z\", \"spec\": {\"hypothesis\": \"Qwen CoNLL-2003 N=16: cross-dataset N-scaling comparison with SciERC N=16\", \"plan_id\": \"exp-002\", \"parent\": \"exp_002_ner_conll2003\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_002_conll_n16\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.4844, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"N\": 16, \"dataset\": \"conll2003\", \"subtask\": \"ner\", \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2614, \"greedy_f1\": 0.907, \"full\": {\"SJ_rho\": 0.4496, \"FK_rho\": 0.3928, \"logprob_rho\": 0.3146, \"EM_rho\": 0.4627, \"voting_conf_rho\": 0.4286, \"SJ_AUROC\": 0.8264, \"FK_AUROC\": 0.7821, \"logprob_AUROC\": 0.7531, \"EM_AUROC\": 0.8409, \"voting_conf_AUROC\": 0.8071, \"SJ_ECE\": 0.0747, \"FK_ECE\": 0.1786, \"logprob_ECE\": 0.2031, \"EM_ECE\": 0.0786, \"voting_conf_ECE\": 0.529}, \"conditional\": {\"SJ_rho\": 0.4208, \"FK_rho\": 0.3494, \"logprob_rho\": 0.3756, \"EM_rho\": 0.4658, \"voting_conf_rho\": 0.3654, \"SJ_AUROC\": 0.8405, \"FK_AUROC\": 0.7819, \"logprob_AUROC\": 0.8259, \"EM_AUROC\": 0.8781, \"voting_conf_AUROC\": 0.7951, \"SJ_ECE\": 0.0982, \"FK_ECE\": 0.1899, \"logprob_ECE\": 0.2504, \"EM_ECE\": 0.0997, \"voting_conf_ECE\": 0.6096}, \"n8_vs_n16_delta_rho_full\": {\"SJ\": 0.0139, \"FK\": -0.007, \"logprob\": -0.0011, \"EM\": 0.012, \"voting_conf\": 0.0049}}, \"checkpoint_path\": \"output/exp_002_conll_n16/samples.jsonl\", \"log_path\": \"output/exp_002_conll_n16.log\", \"completed_at\": \"2026-05-14T18:58:40.473Z\", \"hypothesis\": \"CoNLL N=16 NER: cross-dataset validation on high-performance NER dataset. Tests if structural signals retain advantage when base model performance is already high (greedy F1 > 0.9).\"}, \"exp_012_rerun_1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:11:33.777Z\", \"updated_at\": \"2026-05-18T20:49:42.395Z\", \"spec\": {\"hypothesis\": \"Verify if max_tokens=512 truncation inflated Table 1 N=8 SciERC signal values. Rerun with max_tokens=1024 for clean comparison.\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"parent\": \"exp_012_logprob_baseline\", \"data_count\": 551, \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_012_rerun_1024\", \"checkpoint_path\": \"output/exp_012_rerun_1024/\", \"log_path\": \"output/exp_012_rerun_1024/run.log\", \"data_path\": \"data/scierc/processed_data\"}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.1777, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"ner_full\": {\"n\": 529, \"SJ\": {\"rho\": 0.3599, \"tau\": 0.2646, \"AUROC\": 0.6917, \"ECE\": 0.4531, \"rho_ci95\": [0.2732, 0.4389], \"AUROC_ci95\": [0.6304, 0.7406]}, \"FK\": {\"rho\": 0.2665, \"tau\": 0.1974, \"AUROC\": 0.629, \"ECE\": 0.4512, \"rho_ci95\": [0.1743, 0.3486], \"AUROC_ci95\": [0.5612, 0.6882]}, \"logprob\": {\"rho\": 0.2052, \"tau\": 0.1478, \"AUROC\": 0.5783, \"ECE\": 0.7064, \"rho_ci95\": [0.1171, 0.2904], \"AUROC_ci95\": [0.5179, 0.6387]}, \"EM\": {\"rho\": 0.2945, \"tau\": 0.2208, \"AUROC\": 0.7493, \"ECE\": 0.3526, \"rho_ci95\": [0.2094, 0.37], \"AUROC_ci95\": [0.7002, 0.7928]}, \"voting_conf\": {\"rho\": 0.3792, \"tau\": 0.2805, \"AUROC\": 0.6841, \"ECE\": 0.3807, \"rho_ci95\": [0.2972, 0.4486], \"AUROC_ci95\": [0.6249, 0.7366]}}, \"ner_cond\": {\"n\": 477, \"SJ\": {\"rho\": 0.3113, \"tau\": 0.2257, \"AUROC\": 0.6772, \"ECE\": 0.4416, \"rho_ci95\": [0.2353, 0.3959], \"AUROC_ci95\": [0.621, 0.7337]}, \"FK\": {\"rho\": 0.1761, \"tau\": 0.1284, \"AUROC\": 0.6078, \"ECE\": 0.4389, \"rho_ci95\": [0.0839, 0.2665], \"AUROC_ci95\": [0.5442, 0.6709]}, \"logprob\": {\"rho\": 0.1538, \"tau\": 0.1111, \"AUROC\": 0.5633, \"ECE\": 0.6803, \"rho_ci95\": [0.0637, 0.2424], \"AUROC_ci95\": [0.5032, 0.6232]}, \"EM\": {\"rho\": 0.3596, \"tau\": 0.2735, \"AUROC\": 0.7556, \"ECE\": 0.3257, \"rho_ci95\": [0.2819, 0.4408], \"AUROC_ci95\": [0.7011, 0.8107]}, \"voting_conf\": {\"rho\": 0.3, \"tau\": 0.2189, \"AUROC\": 0.6618, \"ECE\": 0.3746, \"rho_ci95\": [0.2168, 0.3836], \"AUROC_ci95\": [0.6004, 0.7201]}}, \"re_full\": {\"n\": 397, \"SJ\": {\"rho\": 0.2503, \"tau\": 0.1878, \"AUROC\": 0.6702, \"ECE\": 0.3865}, \"FK\": {\"rho\": 0.2752, \"tau\": 0.2117, \"AUROC\": 0.6089, \"ECE\": 0.4405}, \"logprob\": {\"rho\": 0.2662, \"tau\": 0.1951, \"AUROC\": 0.6005, \"ECE\": 0.7694}, \"EM\": {\"rho\": 0.1344, \"tau\": 0.1081, \"AUROC\": 0.7059, \"ECE\": 0.3548}, \"voting_conf\": {\"rho\": 0.3498, \"tau\": 0.2663, \"AUROC\": 0.6935, \"ECE\": 0.2724}}, \"re_cond\": {\"n\": 238, \"SJ\": {\"rho\": 0.2457, \"tau\": 0.1811, \"AUROC\": 0.6463, \"ECE\": 0.2941}, \"FK\": {\"rho\": 0.1139, \"tau\": 0.0876, \"AUROC\": 0.551, \"ECE\": 0.3424}, \"logprob\": {\"rho\": 0.0112, \"tau\": 0.0051, \"AUROC\": 0.5186, \"ECE\": 0.6464}, \"EM\": {\"rho\": 0.4165, \"tau\": 0.3256, \"AUROC\": 0.7515, \"ECE\": 0.2232}, \"voting_conf\": {\"rho\": 0.2409, \"tau\": 0.178, \"AUROC\": 0.642, \"ECE\": 0.207}}, \"delta_vs_512_ner_full_rho\": {\"SJ\": 0.0034, \"FK\": 0.0014, \"EM\": 0.0379, \"voting_conf\": -0.1226, \"logprob\": 0.0656}, \"provenance_note\": \"exp_015_v2 scierc_n8_logprob used exp_012_logprob (max_tokens=512 truncated data). voting_conf was inflated 0.502→0.379, logprob was suppressed 0.140→0.205.\"}, \"completed_at\": \"2026-05-14T23:10:33.075Z\", \"hypothesis\": \"Canonical SciERC baseline with max_tokens=1024: Qwen3-8B ft_002_v2, N=8, T=1.0, seed=42, joint NER+RE. Establishes ground-truth ρ rankings and selection F1 for all 5 signals under correct generation length.\"}, \"exp_llama_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:15:27.504Z\", \"updated_at\": \"2026-05-18T20:49:10.758Z\", \"hypothesis\": \"LLaMA-3.1-8B on SciERC with seed=456 will show consistent 5-signal ranking patterns (SJ/FK > logprob) and DGS selection gains comparable to seed=42 and seed=123, confirming cross-seed stability.\", \"spec\": {\"command\": \"python3 code/analyze_llama_scierc_seed456_5signal.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_018_llama_scierc_seed456/samples.jsonl\", \"data_count\": 551, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"same as seed123\", \"eval_data\": \"SciERC test (551 instances)\", \"checkpoint_path\": \"output/exp_018_llama_scierc_seed456/5signal_dgs_report.json\", \"log_path\": \"output/exp_018_llama_scierc_seed456/run.log\"}, \"metrics\": {\"greedy_f1\": 0.6457, \"oracle_f1\": 0.7574, \"headroom\": 0.1117, \"dgs_f1\": 0.6454, \"degen_rate\": 0.2741, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"rho_SJ_full\": 0.3663, \"rho_FK_full\": 0.3115, \"rho_logprob_full\": 0.1911, \"rho_EM_full\": 0.3088, \"rho_vc_full\": 0.4135, \"auroc_SJ_full\": 0.7061, \"auroc_EM_full\": 0.7538, \"n_valid\": 529, \"n_conditional\": 478}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T19:16:00.973Z\"}, \"exp_007_llama_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:10:26.278Z\", \"updated_at\": \"2026-05-18T20:49:08.934Z\", \"name\": \"LLaMA-3.1-8B SciERC NER inference seed=123\", \"hypothesis\": \"Structural consistency signals (SJ, FK) correlate with entity F1 for LLaMA-8B on SciERC at seed=123, and DGS selection improves over greedy baseline\", \"spec\": {\"command\": \"python3 code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed123\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"LLaMA-3.1-8B-Instruct (SciERC LoRA fine-tuned)\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/llama3.1-8b-scierc-merged\", \"checkpoint_path\": \"checkpoints/llama3.1-8b-scierc-lora\", \"log_path\": \"output/exp_018_llama_scierc_seed123/report.json\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T19:11:30.781Z\", \"metrics\": {\"greedy_f1\": 0.6454, \"oracle_f1\": 0.7657, \"headroom\": 0.1204, \"degen_rate\": 0.2665, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"dgs_delta_pp\": -0.38, \"rho_SJ_full\": 0.3552, \"rho_voting_conf_full\": 0.4193, \"auroc_SJ_full\": 0.7092, \"auroc_EM_full\": 0.7468}}, \"exp_qwen3_4b_conll_scs_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:08:28.512Z\", \"updated_at\": \"2026-05-18T20:49:06.922Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_conll_scs_inference\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"222184\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_qwen3_4b_conll_scs_inference/report.json\", \"submitted_at\": \"2026-05-15T19:10:19.757Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-merged\", \"wall_clock_seconds\": 523.8, \"gpu_hours\": 0.15}, \"metrics\": {\"greedy_f1\": 0.9251, \"oracle_f1\": 0.9408, \"oracle_headroom_pp\": 1.57, \"SJ_rho_full\": 0.4045, \"SJ_rho_cond\": 0.4306, \"FK_rho_full\": 0.3961, \"FK_rho_cond\": 0.42, \"LP_rho_full\": 0.3186, \"LP_rho_cond\": 0.3378, \"LP_auroc_full\": 0.7689, \"LP_auroc_cond\": 0.8153, \"fleiss_kappa_mean\": 0.9349, \"soft_jaccard_mean\": 0.9754, \"structural_beats_surface\": true, \"rho_advantage_pp\": 0.84, \"n_instances\": 3453, \"n_gold_empty_filtered\": 697, \"n_greedy_f1_zero_filtered\": 112, \"verdict\": \"MARGINAL\", \"degen_rate\": 0.9057, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:19:03.585Z\", \"notes\": \"4B CoNLL SCS inference completed. SJ>FK>LP ordering preserved at 4B scale (rho 0.405>0.396>0.319). Greedy F1=0.925 outperforms 8B (0.907), but SJ rho is lower (0.405 vs 0.450 at 8B N=16). Structural beats surface confirmed (+0.84pp). Verdict MARGINAL due to small oracle headroom (1.57pp) — the model is already very good at CoNLL, leaving little room for selection improvement.\", \"hypothesis\": \"CoNLL 4B SCS inference (checkpoint-3800): cross-scale evidence for correlation-selection gap. Tests if structural>surface ranking and LP compression hold at smaller model scale on high-degeneracy dataset.\"}, \"exp_qwen3_4b_conll_scs_inference_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:41:33.501Z\", \"updated_at\": \"2026-05-18T20:49:03.705Z\", \"hypothesis\": \"CoNLL 4B SCS inference with best checkpoint-4200 (from resume training). Scale ablation: cross-scale evidence for correlation-selection gap. Compare vs v1 (ckpt-3800 baseline: greedy_f1=0.9251, SJ_rho=0.4045).\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-conll2003-merged-ckpt4200 --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_conll_scs_inference_v2\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-4B (LoRA checkpoint-4200 merged)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/qwen3-4b-conll2003-lora/checkpoint-4200\", \"gpu\": [\"cuda:1\"], \"checkpoint_path\": \"checkpoints/qwen3-4b-conll2003-merged-ckpt4200\", \"log_path\": \"/tmp/infer_4b_conll_v2.log\", \"account\": \"root\", \"backend\": \"tmux\", \"tmux_session\": \"exp_4b_conll_scs_v2\"}, \"metrics\": {\"greedy_f1\": 0.9234, \"oracle_f1\": 0.9404, \"oracle_headroom_pp\": 1.7, \"SJ_rho_full\": 0.4217, \"SJ_rho_cond\": 0.459, \"FK_rho_full\": 0.4181, \"FK_rho_cond\": 0.4538, \"LP_rho_full\": 0.3313, \"LP_rho_cond\": 0.3487, \"LP_auroc_full\": 0.7761, \"LP_auroc_cond\": 0.8209, \"n_instances\": 3453, \"verdict\": \"MARGINAL\", \"degen_rate\": 0.9057, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:54:14.575Z\", \"notes\": \"Gold-filter audit (2026-05-16): CONSISTENT. _full metrics (SJ_rho=0.4217, FK_rho=0.4181) are computed on gold-filtered set (n=2756), same as 8B Table 1 values. _full does NOT mean all 3453 instances — it means gold-nonempty instances. _cond further excludes greedy-F1=0 (n=2641). Confirmed via run_mvp_pilot.py source code and report.json n values.\"}, \"exp_qwen3_4b_scierc_scs_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:45:33.384Z\", \"updated_at\": \"2026-05-18T20:49:01.260Z\", \"hypothesis\": \"SciERC 4B SCS inference after v4 finetune merge. Complete 2x2 scale matrix (4B SciERC cell). Cross-scale + cross-task evidence for correlation-selection gap.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_scierc_scs_inference\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-4b-scierc-merged (checkpoint-400)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/qwen3-4b-scierc-merged\", \"eval_data\": \"scierc test set\"}, \"metrics\": {\"ner_greedy_f1\": 0.6612, \"ner_oracle_f1\": 0.7839, \"ner_headroom_pp\": 12.28, \"ner_SJ_rho\": 0.4221, \"ner_FK_rho\": 0.3258, \"ner_LP_rho\": 0.28, \"re_greedy_f1\": 0.4136, \"re_oracle_f1\": 0.5846, \"re_headroom_pp\": 17.1, \"re_SJ_rho\": 0.2673, \"re_FK_rho\": 0.3593, \"re_LP_rho\": 0.3512, \"re_sample_f1_pct_zero\": 0.476, \"re_LP_rho_cond\": 0.1135, \"re_LP_rho_cond_p\": 0.074, \"degen_rate\": 0.104, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"checkpoint_path\": \"checkpoints/qwen3-4b-scierc-merged/\", \"log_path\": \"/tmp/exp_qwen3_4b_scierc_scs_inference.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T20:00:03.730Z\"}, \"exp_027_fewnerd_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T05:28:57.036Z\", \"updated_at\": \"2026-05-18T20:48:58.455Z\", \"spec\": {\"hypothesis\": \"LP selection scales with N in low-degeneracy regime: N=16 should yield LP Δ > +2pp (vs N=8 +1.36pp) on Few-NERD (10% degen), because more samples increase oracle headroom while LP ranking remains effective.\", \"parent\": \"exp_021_fewnerd_full\", \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"data_path\": \"data/fewnerd_n16_subset/test.json\", \"data_count\": 5000, \"seed\": 42, \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd_n16_subset --dataset fewnerd --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs --start_index {0,1250,2500,3750} --end_index {1250,2500,3750,5000} --output_dir output/exp_027_fewnerd_n16/shard_{0-3}\", \"checkpoint_path\": \"output/exp_027_fewnerd_n16/sampled_results.jsonl\", \"log_path\": \"output/exp_027_fewnerd_n16/\"}, \"conclusion\": \"success\", \"metrics\": {\"LP_delta_pp\": 1.88, \"LP_delta_95CI\": [1.41, 2.37], \"degen_rate\": 0.0706, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"greedy_f1\": 0.7478, \"lp_sel_f1\": 0.7666, \"oracle_f1\": 0.902, \"headroom_pp\": 15.42, \"all_8_types_positive\": true, \"n_instances\": 5000, \"N_samples\": 16, \"bootstrap_p\": \"<0.001\"}, \"hypothesis\": \"LP selection scales with N in low-degeneracy regime: N=16 should yield LP Δ > +2pp (vs N=8 +1.36pp) on Few-NERD (10% degen), because more samples increase oracle headroom while LP ranking remains effective.\", \"completed_at\": \"2026-05-17T05:46:48.460Z\"}, \"exp_026_t12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T13:18:18.780Z\", \"updated_at\": \"2026-05-18T20:48:24.965Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --n_samples 8 --temperature 1.2 --seed 42 --max_tokens 1024 --collect_logprobs --output_dir output/exp_026_t12\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"log_path\": \"output/exp_026_t12.log\", \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\"}, \"conclusion\": \"success\", \"metrics\": {\"temperature\": 1.2, \"task\": \"T-ablation\", \"degen_rate\": 0.1493, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"completed_at\": \"2026-05-16T14:26:37.648Z\", \"hypothesis\": \"Temperature T=1.2 ablation on SciERC: test if higher temperature increases sample diversity (lower degeneracy) and LP discriminative range, potentially improving LP selection while maintaining structural signal effectiveness.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_026_t08\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:57:46.027Z\", \"updated_at\": \"2026-05-18T20:48:24.112Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_026_t08/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"temperature\": 0.8, \"task\": \"T-ablation\", \"degen_rate\": 0.2382, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"completed_at\": \"2026-05-16T14:26:36.243Z\", \"hypothesis\": \"Temperature T=0.8 ablation on SciERC: test if lower temperature increases LP compression (narrower range) while structural signals remain robust, supporting the claim that LP compression is intrinsic rather than temperature-driven.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_026_t05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:19:35.753Z\", \"updated_at\": \"2026-05-18T20:48:23.339Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_026_t05/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"temperature\": 0.5, \"task\": \"T-ablation\", \"degen_rate\": 0.414, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"completed_at\": \"2026-05-16T14:26:34.808Z\", \"hypothesis\": \"Temperature T=0.5 ablation on SciERC: extreme low temperature expected to maximally compress LP scores and increase degeneracy, providing upper-bound evidence for LP compression as model-intrinsic phenomenon.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_026_T12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T09:38:31.060Z\", \"updated_at\": \"2026-05-18T20:48:22.668Z\", \"hypothesis\": \"T=1.2 will decrease degeneracy rate and expand LP range vs T=1.0, but may degrade generation quality (lower greedy F1). Tests whether reducing degeneracy via higher T recovers selection headroom or if quality degradation offsets the benefit.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-17T09:39:51.733Z\", \"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.2 --seed 42 --output_dir output/exp_026_T12/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T12_run.log\\\"\", \"finished_at\": \"2026-05-17T09:48:04.019Z\", \"training_hours\": 0.14}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.2 --seed 42 --output_dir output/exp_026_T12/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T12_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"381369\", \"log_path\": \"output/exp_026_T12_run.log\", \"submitted_at\": \"2026-05-17T09:41:39.393Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"output/exp_026_T12/\", \"wall_clock_seconds\": 1114.4, \"gpu_hours\": 0.31}, \"pid\": \"381369\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_T12.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T09:48:08.312470+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.1493, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"lp_range_mean\": 0.075, \"lp_range_std\": 0.059, \"within_instance_rho_mean\": 0.2245, \"within_instance_rho_median\": 0.3152, \"within_instance_rho_valid_pct\": 0.875, \"greedy_f1\": 0.62, \"oracle_f1\": 0.758, \"lp_sel_f1\": 0.621, \"sj_sel_f1\": 0.597, \"em_sel_f1\": 0.596, \"vc_sel_f1\": 0.582, \"sj_rho\": 0.384, \"fk_rho\": 0.386, \"lp_rho\": 0.182, \"vc_rho\": 0.342, \"sj_auroc\": 0.683, \"lp_auroc\": 0.566}, \"completed_at\": \"2026-05-17T10:00:13.771Z\"}, \"exp_026_T08\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T09:38:29.602Z\", \"updated_at\": \"2026-05-18T20:48:21.975Z\", \"hypothesis\": \"T=0.8 will show intermediate degeneracy between T=0.5 and T=1.0, establishing a monotonic degeneracy-temperature relationship. If LP selection improves at T=0.8 vs T=1.0, it identifies the optimal operating point for the selection mechanism.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-17T09:39:50.780Z\", \"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.8 --seed 42 --output_dir output/exp_026_T08/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T08_run.log\\\"\", \"finished_at\": \"2026-05-17T09:47:56.543Z\", \"training_hours\": 0.13}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.8 --seed 42 --output_dir output/exp_026_T08/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T08_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"380680\", \"log_path\": \"output/exp_026_T08_run.log\", \"submitted_at\": \"2026-05-17T09:41:20.812Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"output/exp_026_T08/\", \"wall_clock_seconds\": 1131.4, \"gpu_hours\": 0.31}, \"pid\": \"380680\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_T08.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T09:48:02.635244+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.2382, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"lp_range_mean\": 0.043, \"lp_range_std\": 0.042, \"within_instance_rho_mean\": 0.1701, \"within_instance_rho_median\": 0.2635, \"within_instance_rho_valid_pct\": 0.728, \"greedy_f1\": 0.616, \"oracle_f1\": 0.737, \"lp_sel_f1\": 0.627, \"sj_sel_f1\": 0.619, \"em_sel_f1\": 0.611, \"vc_sel_f1\": 0.603, \"sj_rho\": 0.378, \"fk_rho\": 0.34, \"lp_rho\": 0.212, \"vc_rho\": 0.352, \"sj_auroc\": 0.662, \"lp_auroc\": 0.571}, \"completed_at\": \"2026-05-17T10:00:12.248Z\"}, \"exp_026_T05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T09:38:28.066Z\", \"updated_at\": \"2026-05-18T20:48:16.286Z\", \"hypothesis\": \"T=0.5 will increase degeneracy rate (more deterministic outputs) and compress LP range on SciERC, reducing selection headroom. Maps the low-temperature end of the degeneracy-temperature frontier, validating that degeneracy is regime-dependent on sampling temperature.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.5 --seed 42 --output_dir output/exp_026_T05/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T05_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"380188\", \"log_path\": \"output/exp_026_T05_run.log\", \"submitted_at\": \"2026-05-17T09:40:51.787Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"output/exp_026_T05/\", \"wall_clock_seconds\": 1158.3, \"gpu_hours\": 0.32}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": \"380188\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_T05.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.5 --seed 42 --output_dir output/exp_026_T05/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T05_run.log\\\"\", \"finished_at\": \"2026-05-17T09:47:31.332Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T09:47:35.127151+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.414, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"lp_range_mean\": 0.022, \"lp_range_std\": 0.021, \"within_instance_rho_mean\": 0.1306, \"within_instance_rho_median\": 0.2182, \"within_instance_rho_valid_pct\": 0.597, \"greedy_f1\": 0.617, \"oracle_f1\": 0.71, \"lp_sel_f1\": 0.622, \"sj_sel_f1\": 0.622, \"em_sel_f1\": 0.619, \"vc_sel_f1\": 0.61, \"sj_rho\": 0.333, \"fk_rho\": 0.341, \"lp_rho\": 0.208, \"vc_rho\": 0.353, \"sj_auroc\": 0.644, \"lp_auroc\": 0.577}, \"completed_at\": \"2026-05-17T10:00:10.083Z\"}, \"exp_017_llama_conll_n16_s123_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:02.953Z\", \"updated_at\": \"2026-05-18T20:47:52.122Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed123.\", \"parent\": \"exp_017_llama_conll_n16_s123\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 123, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_s123_r1024\", \"data_path\": \"data/conll2003\", \"data_count\": 3453}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T01:20:51.219Z\", \"notes\": \"Output exists on autodl-5090. Registry status corrected from killed to success.\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=123 (max_tokens=1024 rerun): cross-model multi-seed validation. Confirms structural>surface ordering is stable across seeds for LLaMA on CoNLL after gold-filtering correction.\", \"metrics\": {\"degen_rate\": 0.8636, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_018_llama_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:14.370Z\", \"updated_at\": \"2026-05-18T20:47:51.435Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: LLaMA SciERC N=8 seed=123, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 123 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_llama_scierc_seed123\", \"server\": \"autodl-5090\", \"seed\": 123, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed123/\", \"log_path\": \"output/exp_018_llama_scierc_seed123.log\", \"samples_md5\": \"072eeca68236d46b4c5c84b945209abc\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:04.855Z\", \"hypothesis\": \"LLaMA SciERC seed=123: multi-seed cross-model validation. Complements seed42 for LLaMA 3-seed protocol on SciERC NER+RE signal rankings.\", \"metrics\": {\"degen_rate\": 0.2665, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_018_qwen_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:13.570Z\", \"updated_at\": \"2026-05-18T20:47:50.032Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: Qwen SciERC N=8 seed=456, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 456 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_qwen_scierc_seed456\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_qwen_scierc_seed456/\", \"log_path\": \"output/exp_018_qwen_scierc_seed456/run.log\", \"samples_md5\": \"46d0de47ad7693c07e7df3a77c90c3be\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:03.898Z\", \"hypothesis\": \"Qwen SciERC seed=456: multi-seed Qwen validation. Part of 3-seed protocol (seed42=exp_012_rerun_1024, seed123, seed456) for statistical significance of signal rankings.\", \"metrics\": {\"degen_rate\": 0.2042, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_018_qwen_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:12.747Z\", \"updated_at\": \"2026-05-18T20:47:49.306Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: Qwen SciERC N=8 seed=123, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 123 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_qwen_scierc_seed123\", \"server\": \"autodl-5090\", \"seed\": 123, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_qwen_scierc_seed123/\", \"log_path\": \"output/exp_018_qwen_scierc_seed123.log\", \"samples_md5\": \"866a59581dea56f4633149f0b18a31ae\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:02.954Z\", \"hypothesis\": \"Qwen SciERC seed=123: multi-seed Qwen validation. Part of 3-seed protocol (seed42=exp_012_rerun_1024, seed123, seed456) for statistical significance of signal rankings.\", \"metrics\": {\"degen_rate\": 0.172, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_epoch_dgs_analysis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:57.921Z\", \"updated_at\": \"2026-05-18T20:01:46.134Z\", \"hypothesis\": \"DGS benefit is strictly monotonic with degeneracy rate: higher degeneracy → greater DGS improvement, validating that degeneracy rate is the key gating signal\", \"spec\": {\"command\": \"python3 code/epoch_dgs_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/epoch_dgs_analysis_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/epoch_dgs_analysis_results.json\", \"completed_at\": \"2026-05-18T20:01:46.134Z\"}, \"exp_diagnostic_calibration\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:56.064Z\", \"updated_at\": \"2026-05-18T20:01:44.364Z\", \"hypothesis\": \"A 3-indicator regression model (degeneracy rate, LP-F1 correlation, LP range) can quantitatively predict the optimal LP selection delta for unseen instances\", \"spec\": {\"command\": \"python3 code/diagnostic_calibration.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/diagnostic_calibration_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/diagnostic_calibration_results.json\", \"completed_at\": \"2026-05-18T20:01:44.364Z\"}, \"exp_adaptive_temperature\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:52.771Z\", \"updated_at\": \"2026-05-18T20:01:42.646Z\", \"hypothesis\": \"Adjusting sampling temperature based on instance-level confidence indicators can improve output diversity-quality tradeoff\", \"spec\": {\"command\": \"python3 code/adaptive_temperature.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/adaptive_temperature_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/adaptive_temperature_results.json\", \"completed_at\": \"2026-05-18T20:01:42.646Z\"}, \"exp_entity_consensus\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:50.628Z\", \"updated_at\": \"2026-05-18T20:01:40.869Z\", \"hypothesis\": \"Constructing new output from N samples using entity frequency thresholds and LP-weighted decisions can capture complementary information that single-sample selection misses\", \"spec\": {\"command\": \"python3 code/entity_consensus.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/entity_consensus_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/entity_consensus_results.json\", \"completed_at\": \"2026-05-18T20:01:40.869Z\"}, \"exp_ccs_selection\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:48.671Z\", \"updated_at\": \"2026-05-18T20:01:39.128Z\", \"hypothesis\": \"Three-stage cascaded selection (degen→greedy, low-LP-range→entity MV, high-LP-range→LP) can outperform single-strategy selection by adapting to local confidence patterns\", \"spec\": {\"command\": \"python3 code/ccs_selection.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/ccs_selection_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/ccs_selection_results.json\", \"completed_at\": \"2026-05-18T20:01:39.128Z\"}, \"exp_017_llama_conll\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T14:39:32.014Z\", \"updated_at\": \"2026-05-18T19:11:03.240Z\", \"completed_at\": \"2026-05-14T17:12:15.687Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"success\"}}, \"hypothesis\": \"On CoNLL (high degeneracy regime), LLaMA should show the same pattern as Qwen3: LP selection fails due to narrow headroom, but structural signals retain diagnostic value (QE rho). Cross-model validation of the degeneracy-driven signal effectiveness framework.\", \"parent\": \"exp_007_llama_inference\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-17T11:30:53.467Z\"}, \"metrics\": {\"degeneracy_cf1_gold_filtered\": 0.894, \"n_constant_f1\": 2465, \"n_gold_filtered\": 2756, \"n_total\": 3453, \"greedy_f1\": 0.9239, \"oracle_f1\": 0.9451, \"random_f1\": 0.9207, \"headroom_pp\": 2.11, \"dgs_f1\": 0.9254, \"dgs_delta_pp\": 0.14, \"dgs_nondegen_lp_delta_pp\": 1.37, \"selection_f1\": {\"SJ\": {\"f1\": 0.9237, \"delta_pp\": -0.04}, \"FK\": {\"f1\": 0.924, \"delta_pp\": -0.02}, \"VC\": {\"f1\": 0.925, \"delta_pp\": 0.08}, \"EM\": {\"f1\": 0.9244, \"delta_pp\": 0.02}, \"LP\": {\"f1\": 0.9244, \"delta_pp\": 0.02}}, \"qe_rho_full_3seed\": {\"SJ\": {\"mean\": 0.4631, \"sd\": 0.0074}, \"FK\": {\"mean\": 0.4546, \"sd\": 0.0061}, \"EM\": {\"mean\": 0.4603, \"sd\": 0.0078}, \"VC\": {\"mean\": 0.4579, \"sd\": 0.003}, \"LP\": {\"mean\": 0.3099, \"sd\": 0.0055}}, \"qe_auroc_full_3seed\": {\"SJ\": {\"mean\": 0.736, \"sd\": 0.0064}, \"FK\": {\"mean\": 0.732, \"sd\": 0.0063}, \"EM\": {\"mean\": 0.7355, \"sd\": 0.0069}, \"VC\": {\"mean\": 0.7394, \"sd\": 0.0041}, \"LP\": {\"mean\": 0.7629, \"sd\": 0.0044}}, \"lp_range\": {\"mean\": 0.0198, \"std\": 0.0315, \"median\": 0.0002}}, \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/exp017_full_signal_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/samples.jsonl\", \"data_count\": 3453, \"model_name\": \"llama3.1-8b-conll2003-merged\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/full_signal_analysis.json\"}}, \"exp_017_llama_conll_finetune\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:47:36.156Z\", \"updated_at\": \"2026-05-18T18:43:42.649Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli train train_config_llama_conll2003_3ep.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"674921\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_017_llama_conll_finetune.log\", \"submitted_at\": \"2026-05-18T16:47:35.786Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003/llmfactory_train.json\", \"data_count\": 14037, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/llama3.1-8b-conll2003-lora-3ep\", \"checkpoint_source\": \"Meta-Llama-3.1-8B-Instruct (base model, LoRA from scratch)\", \"eval_data\": \"conll2003_uie_dev\", \"wall_clock_seconds\": 6176.5, \"gpu_hours\": 1.72}, \"hypothesis\": \"Structural self-consistency QE signals (SJ, FK, VC, EM) show model-agnostic diagnostic power: their Spearman rho with per-instance F1 should be comparable on LLaMA 3.1-8B as on Qwen 2.5-7B for CoNLL-2003 NER, even though degeneracy rates and absolute F1 may differ.\", \"parent\": \"exp_llama_fewnerd_lora\", \"conclusion\": \"success\", \"metrics\": {\"degeneracy_rate\": 0.853, \"greedy_f1\": 0.928, \"oracle_f1\": 0.951, \"headroom\": 0.023, \"selection_f1\": 0.934, \"full_rho_SJ\": 0.45, \"full_rho_FK\": 0.443, \"full_rho_VC\": 0.437, \"full_rho_EM\": 0.448, \"full_rho_LP\": 0.273, \"full_AUROC_SJ\": 0.752, \"full_AUROC_EM\": 0.753, \"full_AUROC_LP\": 0.739, \"cond_rho_SJ\": 0.454, \"cond_rho_EM\": 0.458, \"cond_rho_LP\": 0.311, \"cond_AUROC_EM\": 0.783, \"cond_AUROC_LP\": 0.804}, \"completed_at\": \"2026-05-18T18:30:32.331Z\"}, \"exp_028_entity_token_lp\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:22:18.594Z\", \"updated_at\": \"2026-05-18T18:23:06.601Z\", \"hypothesis\": \"Full-sequence mean LP underperforms as a quality signal because format/schema tokens dilute the entity-relevant logprob signal; isolating entity-only tokens should yield higher QE correlation and selection F1.\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"python code/exp028_entity_token_lp_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_entity_token_lp/scierc/samples.jsonl\", \"data_count\": 529, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_028_entity_token_lp/analysis_results.json\"}, \"completed_at\": \"2026-05-18T18:22:59.312Z\", \"metrics\": {\"greedy_f1\": 0.643, \"oracle_f1\": 0.7845, \"full_lp_global_rho\": 0.2971, \"entity_text_type_lp_global_rho\": 0.4401, \"full_lp_selection_f1\": 0.6465, \"entity_text_type_lp_selection_f1\": 0.6357, \"dilution_ratio\": 0.32, \"full_lp_within_range_median\": 0.0402, \"entity_text_type_within_range_median\": 0.1346, \"schema_only_within_range_median\": 0.0089}}, \"exp_026_t12_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:28:36.812Z\", \"updated_at\": \"2026-05-18T15:30:33.407Z\", \"hypothesis\": \"Higher temperature (T=1.2) reduces degeneracy rate and increases LP range on SciERC NER, but may degrade absolute generation quality\", \"spec\": {\"command\": \"python code/analyze_exp026_temp_5signal.py --data_path output/exp_026_t12/samples.jsonl --output_dir output/exp_026_t12/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"665522\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_t12_scierc.log\", \"submitted_at\": \"2026-05-18T15:28:56.997Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"output/exp_026_t12/samples.jsonl\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"checkpoint_source\": \"ft_002_v2\", \"eval_data\": \"scierc_test_551\", \"wall_clock_seconds\": 96.4, \"gpu_hours\": 0.03}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T15:30:33.407Z\"}, \"exp_026_t08_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:28:36.084Z\", \"updated_at\": \"2026-05-18T15:30:31.219Z\", \"hypothesis\": \"Moderate temperature (T=0.8) provides intermediate degeneracy/LP-range tradeoff on SciERC NER, testing sensitivity of structural signals to temperature\", \"spec\": {\"command\": \"python code/analyze_exp026_temp_5signal.py --data_path output/exp_026_t08/samples.jsonl --output_dir output/exp_026_t08/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"665386\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_t08_scierc.log\", \"submitted_at\": \"2026-05-18T15:28:55.394Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"output/exp_026_t08/samples.jsonl\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"checkpoint_source\": \"ft_002_v2\", \"eval_data\": \"scierc_test_551\", \"wall_clock_seconds\": 95.8, \"gpu_hours\": 0.03}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T15:30:31.219Z\"}, \"exp_026_t05_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:28:34.135Z\", \"updated_at\": \"2026-05-18T15:30:28.965Z\", \"hypothesis\": \"Lower temperature (T=0.5) increases degeneracy rate and reduces LP range on SciERC NER, as reduced sampling diversity causes more identical outputs\", \"spec\": {\"command\": \"python code/analyze_exp026_temp_5signal.py --data_path output/exp_026_t05/samples.jsonl --output_dir output/exp_026_t05/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"665248\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_t05_scierc.log\", \"submitted_at\": \"2026-05-18T15:28:53.787Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"output/exp_026_t05/samples.jsonl\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"checkpoint_source\": \"ft_002_v2\", \"eval_data\": \"scierc_test_551\", \"wall_clock_seconds\": 95.2, \"gpu_hours\": 0.03}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T15:30:28.965Z\"}, \"exp_027_mlp_verifier\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:39:22.524Z\", \"updated_at\": \"2026-05-18T06:41:51.069Z\", \"metrics\": {\"lr_auroc\": 0.6522, \"mlp_auroc\": 0.6381, \"rf_auroc\": 0.5868, \"mlp_15feat_auroc\": 0.6341, \"lr_sel_f1\": 0.6406, \"mlp_sel_f1\": 0.6278, \"greedy_f1\": 0.6441, \"oracle_f1\": 0.8231, \"best_single_signal_auroc\": 0.6476, \"feature_bottleneck_confirmed\": true}, \"hypothesis\": \"MLP/RF等非线性模型能否通过组合5个QE信号(LP,SJ,FK,EM,VC)超越LR，或通过cross-signal interactions提取额外信息，从而缩小selection gap\", \"spec\": {\"command\": \"python train_mlp_verifier.py --n_samples 16 --cv_folds 5 --seeds 42,123,456\", \"server\": \"a100\", \"data_path\": \"output/exp_001_n16_seed*/samples.jsonl\", \"data_count\": 529, \"model_name\": \"sklearn LR/MLP/RF\", \"seed\": \"42,123,456\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp_027_mlp_verifier/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T06:41:51.069Z\"}, \"exp_028_fewnerd_5epoch\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T07:53:12.913Z\", \"updated_at\": \"2026-05-17T20:29:42.274Z\", \"spec\": {\"hypothesis\": \"Few-NERD low degeneracy (10%) partially due to under-convergence at 3 epochs. 5 epochs should increase degeneracy as model becomes more confident, potentially reducing LP selection gain.\", \"parent\": \"exp_021_fewnerd_full\", \"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0,1,2,3 llamafactory-cli train train_config_fewnerd_5epoch_4gpu.yaml 2>&1 | tee logs/exp_028_4gpu_train.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,1,2,3\", \"data_path\": \"data/fewnerd_uie_train\", \"data_count\": 131767, \"model_name\": \"Qwen3-8B LoRA rank=32\", \"seed\": 42, \"log_path\": \"logs/exp_028_4gpu_train.log\", \"checkpoint_path\": \"checkpoints/qwen3-8b-fewnerd-5epoch-lora\"}, \"conclusion\": \"negative\", \"metrics\": {\"degeneracy_cf1_gold\": 0.3133, \"greedy_f1\": 0.7773, \"lp_sel_delta_pp\": 0.624, \"lp_sel_f1\": 0.7835, \"oracle_f1\": 0.8723, \"within_instance_rho_mean\": 0.4066, \"within_instance_rho_median\": 0.6151}, \"hypothesis\": \"Few-NERD low degeneracy (10%) partially due to under-convergence at 3 epochs. 5 epochs should increase degeneracy as model becomes more confident, potentially reducing LP selection gain.\", \"completed_at\": \"2026-05-17T20:29:42.274Z\"}, \"exp_028\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T07:35:39.447Z\", \"updated_at\": \"2026-05-17T20:26:59.399Z\", \"hypothesis\": \"Few-NERD low degeneracy (10%) in exp-021 is NOT due to under-convergence at 3 epochs; training for 5 epochs will show similar degeneracy levels, confirming the structural property of this dataset rather than an artifact of insufficient training.\", \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"completed_at\": \"2026-05-17T12:09:43.334Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}, \"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T20:06:01.040147+00:00\"}]}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0,1,2,3 llamafactory-cli train train_config_fewnerd_5epoch_4gpu.yaml 2>&1 | tee logs/exp_028_4gpu_train.log\\\"\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd_uie_train\", \"data_count\": 131767, \"model_name\": \"Qwen3-8B LoRA rank=32\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-fewnerd-5epoch-lora\", \"log_path\": \"logs/exp_028_4gpu_train.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T20:05:57.260Z\"}, \"conclusion\": \"negative\", \"metrics\": {\"degeneracy_cf1_gold\": 0.313, \"greedy_f1\": 0.7773, \"lp_sel_f1\": 0.7835, \"lp_sel_delta_pp\": 0.62, \"oracle_f1\": 0.8723, \"within_instance_rho\": 0.4066, \"train_loss\": 0.0189, \"eval_loss\": 0.0311}}, \"exp_024_claim_audit\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:54:36.291Z\", \"updated_at\": \"2026-05-17T10:55:08.244Z\", \"hypothesis\": \"Systematic cross-chapter numerical consistency audit: verify all quantitative claims in paper against source experiment data, catch stale values and cross-reference errors before submission.\", \"conclusion\": \"success\", \"metrics\": {\"consistent\": 97, \"errors\": 1, \"warnings\": 5, \"old_residuals_found\": 0}, \"spec\": {\"checkpoint_path\": \"artifacts/exp_024_claim_audit/audit_report.md\", \"log_path\": \"N/A\", \"command\": \"CPU-only paper audit\", \"server\": \"local\", \"data_path\": \"docs/paper/\", \"data_count\": 0, \"model_name\": \"N/A\", \"seed\": 0}, \"completed_at\": \"2026-05-17T10:55:08.244Z\"}, \"exp_016_rerun_1024_bootstrap\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:44:21.577Z\", \"updated_at\": \"2026-05-17T03:33:39.786Z\", \"hypothesis\": \"3-seed bootstrap significance test for NER logprob vs greedy selection gap (+0.6pp). Tests whether the observed advantage is statistically significant.\", \"spec\": {\"command\": \"python code/bootstrap_significance.py\", \"server\": \"local\", \"data_path\": \"output/exp_016_rerun_1024/\", \"data_count\": 529, \"model_name\": \"N/A (statistical analysis)\", \"seed\": \"3-seed bootstrap (1000 iterations)\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp_016_rerun_1024_bootstrap/\"}, \"conclusion\": \"negative\", \"metrics\": {\"bootstrap_ci_95\": [-0.03, 0.042], \"permutation_p\": 0.39, \"cohen_d\": 0.038, \"sign_test_win_rate\": 0.466, \"ner_logprob_vs_greedy_delta\": 0.006, \"conclusion_summary\": \"NER selection: no signal significantly outperforms greedy; RE: same conclusion\"}, \"completed_at\": \"2026-05-14T23:44:48.818Z\", \"parent\": \"exp_016_rerun_1024\"}, \"exp_verbalized_confidence\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:45:20.552Z\", \"updated_at\": \"2026-05-17T03:33:39.197Z\", \"hypothesis\": \"Verbalized confidence baseline: let model self-rate extraction confidence. If also compressed → strengthens \\\"score compression is general\\\" claim. If effective → important positive finding requiring narrative adjustment.\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_verbalized_confidence.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_rerun_1024/samples.jsonl + output/exp002_conll2003/samples.jsonl\", \"data_count\": 3285, \"model_name\": \"qwen3-8b-scierc-merged-v2 + qwen3-8b-conll2003-merged\", \"seed\": 42, \"checkpoint_path\": \"output/review_round9_experiments/verbalized_confidence/\", \"log_path\": \"output/review_round9_experiments/verbalized_confidence_run.log\"}, \"completed_at\": \"2026-05-16T03:09:39.916Z\", \"metrics\": {\"scierc\": {\"VerbConf_rho\": 0.2965, \"VerbConf_auroc\": 0.6811, \"VerbConf_sel_f1\": 0.6195, \"VerbConf_delta\": -0.0245, \"best_existing_rho\": 0.3792, \"VerbConf_mean\": 8.58, \"VerbConf_std\": 1.15, \"parse_fail_rate\": 0.0026}, \"conll\": {\"VerbConf_rho\": 0.3366, \"VerbConf_auroc\": 0.7469, \"VerbConf_sel_f1\": 0.8886, \"VerbConf_delta\": -0.0193, \"best_existing_rho\": 0.4507, \"VerbConf_mean\": 9.24, \"VerbConf_std\": 1.32, \"parse_fail_rate\": 0}}, \"parent\": \"exp_012_rerun_1024\"}, \"exp_entity_token_lp\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T05:39:44.631Z\", \"updated_at\": \"2026-05-17T03:33:38.371Z\", \"hypothesis\": \"Entity-token LP: test Discussion hypothesis (d) format-token dilution. Re-inference with per-token logprobs, then compute entity-only LP variance and selection F1. If entity-token LP compression is reduced → pilot remedy for LP selection. Also includes LP z-score normalization as zero-cost baseline. Addresses SF2+SF3 from Round 12.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1\", \"started_at\": \"2026-05-16T05:41:33.768Z\"}, \"conclusion\": \"negative\", \"metrics\": {\"scierc_ner\": {\"greedy_f1\": 0.643, \"full_lp_sel_f1\": 0.6465, \"entity_lp_sel_f1\": 0.6262, \"oracle_f1\": 0.7845, \"entity_lp_delta_vs_full_lp\": -0.0203}, \"conll_ner\": {\"greedy_f1\": 0.9065, \"full_lp_sel_f1\": 0.8989, \"entity_lp_sel_f1\": 0.8659, \"oracle_f1\": 0.948, \"entity_lp_delta_vs_full_lp\": -0.033}, \"finding\": \"entity-token LP strictly worse than full-sequence LP; CoNLL entity tokens saturated (79.4% tied), SciERC entity tokens too sparse (5.3% of total)\"}, \"spec\": {\"command\": \"python analyze_entity_token_lp.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_rerun_1024/ + output/exp_002_conll_rerun_1024/\", \"data_count\": \"529 (SciERC NER) + 2756 (CoNLL NER)\", \"model_name\": \"Qwen3-8B (finetuned)\", \"seed\": 42, \"checkpoint_path\": \"artifacts/exp_entity_token_lp/results.json\", \"log_path\": \"artifacts/exp_entity_token_lp/report.md\"}, \"completed_at\": \"2026-05-16T06:28:46.845Z\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_freeform_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:42:22.868Z\", \"updated_at\": \"2026-05-17T03:33:37.623Z\", \"spec\": {\"command\": \"python run_freeform_inference.py --seed 42 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"169042\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_ablation.log\", \"submitted_at\": \"2026-05-15T09:42:30.236Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"hypothesis\": \"Free-form decoding recovers logprob variance and selection ability lost under constrained decoding\", \"plan_id\": \"exp-018\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"tmux_session\": \"exp_freeform_ablation\", \"wall_clock_seconds\": 1059.0, \"gpu_hours\": 0.29}, \"conclusion\": \"negative\", \"metrics\": {\"lp_std_ratio_free_vs_constrained\": 0.97, \"lp_range_ratio\": 0.96, \"tied_fraction_constrained\": 0.597, \"tied_fraction_freeform\": 0.577, \"ner_selection_gap_constrained\": 0.0059, \"ner_selection_gap_freeform\": 0.0018, \"re_selection_gap_constrained\": -0.0068, \"re_selection_gap_freeform\": 0.0169, \"parse_rate\": 0.9995, \"ner_vc_rho_constrained\": 0.3792, \"ner_vc_rho_freeform\": 0.4089}, \"checkpoint_path\": \"N/A (inference-only experiment)\", \"completed_at\": \"2026-05-15T10:00:09.238Z\", \"hypothesis\": \"Free-form vs constrained decoding ablation on SciERC: test if removing JSON schema constraint changes LP variance distribution. If LP remains compressed under free-form, confirms compression is model-intrinsic not format-artifact.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_008_re_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:03:06.876Z\", \"updated_at\": \"2026-05-17T02:58:19.490Z\", \"spec\": {\"hypothesis\": \"RE N=16 confirms negative finding with higher statistical power. If rho still <0.30, task-complexity boundary is robust.\", \"plan_id\": \"exp-008\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"gpu\": \"cuda:2\", \"server\": \"gpu-5090-4x-2\", \"gpu_budget_hours\": 12, \"description\": \"RE N=16 on SciERC to confirm negative finding. Inference with log-prob capture.\", \"priority\": \"P1\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"seed\": 42, \"num_instances\": 200, \"partial\": true, \"note\": \"Only 200/551 instances due to --num_test default bug. Needs full rerun.\"}, \"metrics\": {\"ner\": {\"greedy_f1\": 0.6635, \"oracle_f1\": 0.8208, \"headroom\": 0.1572, \"rho_sj_full\": 0.377, \"rho_fk_full\": 0.2508, \"rho_logprob_full\": 0.3153, \"rho_sj_cond\": 0.3598, \"rho_fk_cond\": 0.2251, \"rho_logprob_cond\": 0.2927, \"sj_beats_fk\": true, \"rho_advantage\": 0.1262}, \"re\": {\"greedy_f1\": 0.4339, \"oracle_f1\": 0.6658, \"headroom\": 0.2319, \"rho_sj_full\": 0.2966, \"rho_fk_full\": 0.2871, \"rho_logprob_full\": 0.2986, \"rho_sj_cond\": 0.3975, \"rho_fk_cond\": 0.3774, \"rho_logprob_cond\": 0.2745, \"sj_beats_fk\": true, \"rho_advantage\": 0.0095}, \"verdict\": \"FAIL\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp008_re_n16/\", \"completed_at\": \"2026-05-14T12:28:39.268Z\", \"hypothesis\": \"RE N=16 initial evaluation: first relation extraction test with structural signals. Establishes baseline RE signal effectiveness before pipeline corrections.\"}, \"exp_001_ner_n16_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:46:06.430Z\", \"updated_at\": \"2026-05-17T02:58:18.225Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=3 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --output_dir output/exp001_n16_seed123 --num_test 9999 --collect_logprobs 2>&1 | tee output/exp001_n16_seed123_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"63407\", \"log_path\": \"output/exp001_n16_seed123_run.log\", \"submitted_at\": \"2026-05-14T12:46:06.234Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 551, \"data_path\": \"data/scierc/processed_data\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"checkpoint_path\": \"output/exp001_n16_seed123/\", \"wall_clock_seconds\": 2748.0, \"gpu_hours\": 0.76}, \"conclusion\": \"success\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.663, \"oracle_f1\": 0.809, \"headroom\": 0.146, \"rho_sj\": 0.423, \"rho_fk\": 0.29, \"rho_logprob\": 0.239, \"rho_sj_cond\": 0.423, \"rho_fk_cond\": 0.26}, \"re\": {\"greedy_f1\": 0.419, \"oracle_f1\": 0.625, \"headroom\": 0.206, \"rho_sj\": 0.267, \"rho_fk\": 0.315, \"rho_sj_cond\": 0.364, \"rho_fk_cond\": 0.331}, \"verdict\": \"FAIL\", \"verdict_note\": \"RE rho_sj=0.267 < 0.40; RE >30% samples F1=0\", \"n_instances\": 551, \"seed\": 123, \"N\": 16, \"T\": 1}, \"completed_at\": \"2026-05-14T13:31:54.232Z\", \"hypothesis\": \"SciERC NER N=16 seed=123: multi-seed validation at N=16. Tests seed stability for signal rankings with more samples.\"}, \"exp_007_ner_multi_model\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:20.748Z\", \"updated_at\": \"2026-05-17T02:58:16.747Z\", \"spec\": {\"command\": \"bash -c 'source env.sh && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_llama.yaml'\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"60970\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\", \"submitted_at\": \"2026-05-14T12:43:09.108Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data\", \"data_count\": 1861, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 42, \"log_file\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\", \"wall_clock_seconds\": 165.8, \"gpu_hours\": 0.05}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-14T11:43:50.977Z\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:45:54.952Z\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/llama3.1-8b-scierc-lora\", \"metrics\": {\"epoch\": 5, \"train_loss\": 0.0767, \"eval_loss\": 0.1049, \"train_runtime_sec\": 1494.5, \"train_samples_per_second\": 6.226, \"checkpoints\": [\"checkpoint-400\", \"checkpoint-500\", \"checkpoint-585\"], \"base_model\": \"Meta-Llama-3.1-8B-Instruct\", \"lora_r\": 32, \"lora_alpha\": 64, \"note\": \"EXIT_CODE=129 (SIGHUP) but training completed all 5 epochs before signal. Checkpoint fully intact.\"}, \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\", \"hypothesis\": \"Multi-model NER comparison: evaluates signal effectiveness across Qwen and LLaMA on SciERC NER. Establishes cross-model generalization of structural>surface ranking.\"}, \"exp_003_ner_wnut17\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:17.544Z\", \"updated_at\": \"2026-05-17T02:58:14.928Z\", \"spec\": {\"merged_model_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-merged\", \"pilot_command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-wnut17-merged --data_dir data/wnut17 --dataset wnut17 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp003_wnut17_pilot --num_test 9999 --collect_logprobs\", \"pilot_pid\": 71498, \"pilot_server\": \"autodl-5090\", \"pilot_started_at\": \"2026-05-14T21:36:00Z\", \"test_samples\": 1287}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-14T11:43:50.537Z\", \"finished_at\": \"2026-05-14T12:53:13.262Z\", \"training_hours\": 1.16}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T12:53:14.768981+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-merged\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.525, \"oracle_f1\": 0.664, \"headroom\": 0.139, \"rho_sj_full\": 0.082, \"rho_fk_full\": 0.124, \"rho_logprob_full\": -0.414, \"rho_sj_cond\": 0.275, \"rho_fk_cond\": 0.164, \"rho_logprob_cond\": 0.352, \"sj_beats_logprob_cond\": false}, \"n_instances\": 1287, \"n_gold_empty\": 598, \"sample_f1_mean\": 0.401, \"sample_f1_pct_zero\": 53.7, \"N\": 16, \"T\": 1, \"seed\": 42, \"verdict\": \"FAIL\", \"verdict_note\": \">30% samples F1=0; structural rho weak; logprob baseline stronger\"}, \"conclusion\": \"negative\", \"log_path\": \"output/exp003_wnut17_pilot/\", \"completed_at\": \"2026-05-14T13:40:20.979Z\", \"hypothesis\": \"WNUT-17 NER fine-tune + inference: initial attempt on social media domain. Tests if structural signals work when model capability is low on noisy text with novel entity types.\"}, \"exp_001_seed456_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:41.067Z\", \"updated_at\": \"2026-05-17T02:58:12.996Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:05.416Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:05.021Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:10.317185+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.414, \"rho_fk\": 0.298}, \"re\": {\"rho_sj\": 0.268, \"rho_fk\": 0.26}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 456, \"source\": \"reviewer_verified_report_json\"}, \"hypothesis\": \"SciERC NER seed=456 T=1.0 full: early multi-seed NER test before pipeline corrections. Preliminary evidence for seed stability.\"}, \"exp_001_seed123_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:42.503Z\", \"updated_at\": \"2026-05-17T02:58:11.623Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:13.823Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:13.213Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:16.532801+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.417, \"rho_fk\": 0.283}, \"re\": {\"rho_sj\": 0.265, \"rho_fk\": 0.315}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 123, \"source\": \"reviewer_verified_report_json\"}, \"hypothesis\": \"SciERC NER seed=123 T=1.0 full: early multi-seed NER test before pipeline corrections. Preliminary evidence for seed stability.\"}, \"exp_008_re_n16_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:42.867Z\", \"updated_at\": \"2026-05-17T02:58:10.171Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:18.988Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:19.577Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:21.528032+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.444}, \"re\": {\"rho_sj\": 0.248}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 42, \"mode\": \"RE-only\", \"source\": \"director_corrected\"}, \"hypothesis\": \"RE N=16 T=1.0 full dataset: early RE evaluation attempt. Tests structural signals on relation extraction before pipeline corrections.\"}, \"exp_007_llama_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:54:48.055Z\", \"updated_at\": \"2026-05-17T02:58:03.014Z\", \"spec\": {\"command\": \"python run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp007_llama_inference/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"75172\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_llama_inference.log\", \"submitted_at\": \"2026-05-14T13:54:47.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Meta-Llama-3.1-8B-Instruct (LoRA fine-tuned on SciERC)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/llama3.1-8b-scierc-merged\", \"description\": \"LLaMA-3.1-8B SciERC joint inference (NER+RE) with 8 samples, T=1.0, logprobs collected.\", \"wall_clock_seconds\": 1038.5, \"gpu_hours\": 0.29}, \"log_path\": \"output/exp007_llama_inference/\", \"checkpoint_path\": \"N/A\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.66, \"oracle_f1\": 0.781, \"headroom\": 0.121, \"rho_fk\": 0.327, \"rho_sj\": 0.363, \"rho_fk_cond\": 0.226, \"rho_sj_cond\": 0.311, \"rho_logprob\": 0.183, \"rho_logprob_cond\": 0.109, \"structural_beats_surface\": true, \"sample_f1_pct_zero\": 11.6}, \"re\": {\"greedy_f1\": 0.434, \"oracle_f1\": 0.568, \"headroom\": 0.135, \"rho_fk\": 0.305, \"rho_sj\": 0.299, \"rho_fk_cond\": 0.259, \"rho_sj_cond\": 0.405, \"rho_logprob\": 0.288, \"rho_logprob_cond\": 0.092, \"structural_beats_surface\": false, \"sample_f1_pct_zero\": 41.2}, \"n_instances\": 551, \"N\": 8, \"T\": 1, \"seed\": 42, \"model\": \"LLaMA-3.1-8B-Instruct\", \"verdict\": \"FAIL\", \"verdict_note\": \"RE rho_sj_full=0.299 < 0.40; >30% RE samples F1=0\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T14:12:06.442Z\", \"hypothesis\": \"LLaMA SciERC N=8 baseline: first cross-model test. Verifies structural signal effectiveness generalizes from Qwen to LLaMA model family on SciERC NER.\"}, \"exp_003_wnut17_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:47:34.654Z\", \"updated_at\": \"2026-05-17T02:58:01.627Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-wnut17-merged --data_dir data/wnut17 --dataset wnut17 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp003_wnut17_eval --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/wnut17\", \"data_count\": 1287, \"model_name\": \"qwen3-8b-wnut17-merged\", \"seed\": 42}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T14:08:17.429Z\", \"metrics\": {\"greedy_f1\": 0.523, \"oracle_f1\": 0.664, \"headroom\": 0.141, \"rho_fk\": 0.125, \"rho_sj\": 0.089, \"rho_fk_cond\": 0.169, \"rho_sj_cond\": 0.288, \"rho_logprob_full\": -0.409, \"rho_logprob_cond\": 0.35, \"structural_beats_surface\": false, \"sample_f1_pct_zero\": 53.7, \"n_instances\": 1287, \"N\": 16, \"T\": 1, \"seed\": 42, \"model\": \"Qwen3-8B\", \"n_gold_empty_filtered\": 598, \"verdict\": \"FAIL\", \"verdict_note\": \"structural_beats_surface=false; >50% samples F1=0\"}, \"hypothesis\": \"WNUT-17 NER evaluation: initial test on noisy social media domain. Tests boundary conditions for structural signal effectiveness on out-of-domain text.\"}, \"exp_010_selection_curves\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:01:53.585Z\", \"updated_at\": \"2026-05-17T02:58:00.378Z\", \"spec\": {\"command\": \"python3 code/exp010_selection_curves.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2, output/exp_008_re_n16_v2, output/exp002_conll2003\", \"data_count\": \"551+397+3453 instances\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"description\": \"Best-of-N selection curves: F1 vs N for 7 signals across 3 datasets\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"/tmp/exp010.log\", \"completed_at\": \"2026-05-14T15:02:22.638Z\", \"metrics\": {\"scierc_ner\": {\"n_instances\": 551, \"greedy_f1\": 0.618, \"N16\": {\"oracle\": 0.787, \"SJ\": 0.62, \"FK\": 0.621, \"logprob\": 0.621, \"voting_conf\": 0.585, \"EM\": 0.606, \"random\": 0.595}, \"N8\": {\"oracle\": 0.752, \"SJ\": 0.614, \"FK\": 0.614, \"logprob\": 0.619, \"voting_conf\": 0.591, \"EM\": 0.603, \"random\": 0.589}, \"N4\": {\"oracle\": 0.714, \"SJ\": 0.607, \"FK\": 0.608, \"logprob\": 0.616, \"voting_conf\": 0.594, \"EM\": 0.6, \"random\": 0.587}}, \"scierc_re\": {\"n_instances\": 397, \"greedy_f1\": 0.403, \"N16\": {\"oracle\": 0.631, \"SJ\": 0.397, \"FK\": 0.396, \"logprob\": 0.41, \"voting_conf\": 0.408, \"EM\": 0.381, \"random\": 0.364}, \"N8\": {\"oracle\": 0.583, \"SJ\": 0.393, \"FK\": 0.394, \"logprob\": 0.413, \"voting_conf\": 0.398, \"EM\": 0.381, \"random\": 0.363}}, \"conll_ner\": {\"n_instances\": 3453, \"greedy_f1\": 0.725, \"N8\": {\"oracle\": 0.757, \"SJ\": 0.718, \"FK\": 0.717, \"logprob\": 0.716, \"voting_conf\": 0.714, \"EM\": 0.716, \"random\": 0.69}, \"N4\": {\"oracle\": 0.746, \"SJ\": 0.714, \"FK\": 0.714, \"logprob\": 0.715, \"voting_conf\": 0.714, \"EM\": 0.712, \"random\": 0.692}}}, \"hypothesis\": \"Selection curve analysis: plots selection F1 vs confidence threshold for each signal. Visualizes where correlation-selection gap emerges and at what confidence level signals become useful for filtering.\"}, \"exp_007_llama_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:50.628Z\", \"updated_at\": \"2026-05-17T02:57:59.595Z\", \"spec\": {\"description\": \"LLaMA 3.1-8B SciERC joint extraction, seed=456, cross-model robustness test\", \"hypothesis\": \"Structural consistency generalizes across model architectures (LLaMA vs Qwen)\", \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_seed456\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 456, \"gpu\": [\"cuda:2\"], \"backend\": \"tmux\", \"tmux_session\": \"exp007_s456\", \"account\": \"root\", \"log_path\": \"output/exp_007_llama_seed456/run.log\"}, \"conclusion\": \"negative\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed456/run.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed456/\", \"completed_at\": \"2026-05-14T15:19:20.693Z\", \"metrics\": {\"verdict\": \"FAIL\", \"ner\": {\"greedy_f1\": 0.6597, \"oracle_f1\": 0.7575, \"oracle_headroom\": 0.0978, \"fleiss_kappa\": 0.4543, \"soft_jaccard\": 0.7491, \"rho_kappa_f1\": 0.3115, \"rho_sj_f1\": 0.3663, \"structural_gt_surface\": true}, \"re\": {\"greedy_f1\": 0.4334, \"oracle_f1\": 0.5789, \"oracle_headroom\": 0.1455, \"fleiss_kappa\": 0.3791, \"soft_jaccard\": 0.6782, \"rho_kappa_f1\": 0.3013, \"rho_sj_f1\": 0.287, \"structural_gt_surface\": false}, \"logprob_ner\": {\"rho\": 0.1911, \"auroc\": 0.5989}, \"logprob_re\": {\"rho\": 0.3246, \"auroc\": 0.6678}, \"fail_reason\": \"RE rho_sj=0.2870 < 0.40 threshold; >30% samples F1=0\"}, \"hypothesis\": \"LLaMA SciERC seed=456: early cross-model multi-seed test. Verifies LLaMA NER signal pattern is reproducible across sampling seeds.\"}, \"exp_007_llama_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:50.157Z\", \"updated_at\": \"2026-05-17T02:57:58.879Z\", \"spec\": {\"description\": \"LLaMA 3.1-8B SciERC joint extraction, seed=123, cross-model robustness test\", \"hypothesis\": \"Structural consistency generalizes across model architectures (LLaMA vs Qwen)\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_seed123\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 123, \"gpu\": [\"cuda:1\"], \"backend\": \"tmux\", \"tmux_session\": \"exp007_s123\", \"account\": \"root\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed123/run.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed123/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T15:19:43.424Z\", \"metrics\": {\"verdict\": \"FAIL\", \"ner\": {\"greedy_f1\": 0.6605, \"oracle_f1\": 0.7703, \"headroom\": 0.1098, \"fleiss_kappa\": 0.4553, \"soft_jaccard\": 0.7525, \"rho_kappa_f1\": 0.2143, \"rho_sj_f1\": 0.3371, \"structural_gt_surface\": true}, \"re\": {\"greedy_f1\": 0.433, \"oracle_f1\": 0.5719, \"headroom\": 0.1389, \"fleiss_kappa\": 0.3851, \"soft_jaccard\": 0.6911, \"rho_kappa_f1\": 0.2844, \"rho_sj_f1\": 0.268, \"structural_gt_surface\": false}, \"fail_reasons\": [\"RE rho_sj=0.2680 < 0.40 threshold\", \">30% samples F1=0 (RE: 41.0%)\", \"RE structural not > surface (delta=-0.0165)\"]}, \"hypothesis\": \"LLaMA SciERC seed=123: early cross-model multi-seed test. Verifies LLaMA NER signal pattern is reproducible across sampling seeds.\"}, \"exp_008_re_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:51.386Z\", \"updated_at\": \"2026-05-17T02:57:58.166Z\", \"spec\": {\"description\": \"RE N=16 on SciERC, seed=123, seed robustness test for relation extraction\", \"hypothesis\": \"Structural consistency correlates with per-instance RE F1, robust across seeds\", \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_008_re_seed123\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": [\"cuda:3\"], \"backend\": \"tmux\", \"tmux_session\": \"exp008_rs123\", \"account\": \"root\", \"log_path\": \"output/exp_008_re_seed123/run.log\"}, \"log_path\": \"output/exp_008_re_seed123/run.log\", \"conclusion\": \"negative\", \"metrics\": {\"greedy_f1\": 0.4229, \"oracle_f1\": 0.6244, \"oracle_headroom\": 0.2015, \"fleiss_kappa_mean\": 0.3455, \"soft_jaccard_mean\": 0.6126, \"sample_f1_mean\": 0.3594, \"sample_f1_std\": 0.3793, \"sample_f1_zero_pct\": 44.1, \"structural_gt_surface\": false, \"rho_kappa_f1_full\": 0.3174, \"rho_sj_f1_full\": 0.2835, \"rho_kappa_f1_cond\": 0.0766, \"rho_sj_f1_cond\": 0.2877, \"logprob_auroc_full\": 0.6499, \"logprob_auroc_cond\": 0.5265, \"verdict\": \"FAIL\"}, \"checkpoint_path\": \"N/A\", \"completed_at\": \"2026-05-14T15:21:39.591Z\", \"hypothesis\": \"RE seed=123 multi-seed: tests reproducibility of RE signal rankings. Hypothesis: RE signals weaker than NER due to higher zero-F1 rate, but ranking should be seed-stable.\"}, \"exp_001_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:02.350Z\", \"updated_at\": \"2026-05-17T02:57:57.324Z\", \"spec\": {\"description\": \"NER N=16 on SciERC, seed=42, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency (Fleiss kappa, Soft Jaccard) correlates with per-instance NER F1 on SciERC\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 42, \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed42_v2\", \"gpu\": [\"cuda:1\"], \"pid\": \"78728\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_001_seed42_v2/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"sj_rho_full\": 0.428, \"sj_rho_cond\": 0.369, \"structural_minus_surface\": 0.147, \"conclusion_note\": \"NER seed42 robustness confirmed, structural>surface +0.147\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:34.091Z\", \"log_path\": \"output/exp_001_seed42_v2/\", \"hypothesis\": \"SciERC NER seed=42 v2: primary seed baseline under corrected pipeline. Establishes canonical signal rankings (SJ>FK>LP) for NER with gold-filtering.\"}, \"exp_001_seed123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:04.210Z\", \"updated_at\": \"2026-05-17T02:57:42.106Z\", \"spec\": {\"description\": \"NER N=16 on SciERC, seed=123, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency (Fleiss kappa, Soft Jaccard) correlates with per-instance NER F1 on SciERC (seed robustness check)\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 123, \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed123_v2\", \"gpu\": [\"cuda:2\"], \"pid\": \"78733\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_001_seed123_v2/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"sj_rho_full\": 0.424, \"sj_rho_cond\": 0.376, \"structural_minus_surface\": 0.149, \"conclusion_note\": \"NER seed123 robustness confirmed, structural>surface +0.149\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:35.076Z\", \"log_path\": \"output/exp_001_seed123_v2/\", \"hypothesis\": \"SciERC NER seed=123 v2: second seed for multi-seed validation. Establishes reproducibility of structural>surface signal ranking across random seeds.\"}, \"exp_008_re_n16_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:06.296Z\", \"updated_at\": \"2026-05-17T02:57:41.178Z\", \"spec\": {\"description\": \"RE N=16 on SciERC full set confirmation, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency correlates with per-instance RE F1 on SciERC full dataset\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 42, \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_008_re_n16_v2\", \"gpu\": [\"cuda:3\"], \"pid\": \"78737\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_008_re_n16_v2/run.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"sj_rho_full\": 0.281, \"sj_rho_cond\": 0.308, \"f1_zero_pct\": 44.3, \"conclusion_note\": \"RE N=16 v2 negative: SJ weak, 44.3% F1=0\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:35.598Z\", \"log_path\": \"output/exp_008_re_n16_v2/\", \"hypothesis\": \"RE N=16 evaluation v2: tests structural signal effectiveness on relation extraction at higher sample count. Hypothesis: SJ/FK benefit from more samples on RE task where zero-F1 rate is high.\"}, \"exp_005_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:28:14.924Z\", \"updated_at\": \"2026-05-17T02:57:38.756Z\", \"spec\": {\"description\": \"Temperature sensitivity analysis: T=0.7 vs T=1.0 across 5 signals (SJ, FK, logprob, EM, voting_conf)\", \"command\": \"python code/analyze_exp005_v2_temperature.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/mvp_pilot_004 + output/mvp_pilot_005 + output/exp_012_logprob\", \"data_count\": 551, \"model_name\": \"Qwen3-8B-SciERC-LoRA\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp_005_v2_temperature/temperature_sensitivity_report.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:28:35.949Z\", \"hypothesis\": \"Selection F1 analysis v2: compute actual selection F1 (pick best sample by each signal) vs greedy and oracle. First evidence of correlation-selection gap under corrected pipeline.\"}, \"exp_006_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:30:02.348Z\", \"updated_at\": \"2026-05-17T02:57:36.914Z\", \"spec\": {\"command\": \"python3 code/exp_006_v2_selection.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_{001_seed42,001_seed123,002_conll,008_re}_v2/\", \"data_count\": 4952, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"output/exp_006_v2/exp_006_v2_results.json\", \"log_path\": \"output/exp_006_v2_run.log\", \"completed_at\": \"2026-05-14T15:30:32.474Z\", \"metrics\": {\"NER_SciERC_s42\": {\"greedy\": 0.618, \"oracle\": 0.787, \"SJ\": 0.62, \"logprob\": 0.621, \"FK\": 0.621, \"EM\": 0.606, \"voting_conf\": 0.585, \"random\": 0.586}, \"NER_SciERC_s123\": {\"greedy\": 0.618, \"oracle\": 0.785, \"SJ\": 0.617, \"logprob\": 0.618, \"FK\": 0.621, \"EM\": 0.613, \"voting_conf\": 0.584, \"random\": 0.583}, \"NER_CoNLL\": {\"greedy\": 0.725, \"oracle\": 0.757, \"SJ\": 0.718, \"logprob\": 0.716, \"FK\": 0.717, \"EM\": 0.716, \"voting_conf\": 0.714, \"random\": 0.692}, \"RE_SciERC\": {\"greedy\": 0.403, \"oracle\": 0.631, \"SJ\": 0.397, \"logprob\": 0.41, \"FK\": 0.396, \"EM\": 0.381, \"voting_conf\": 0.408, \"random\": 0.364}}, \"hypothesis\": \"Temperature sensitivity v2: tests signal effectiveness at T=0.5,0.7,1.0,1.2. Hypothesis: structural signals are temperature-robust while LP degrades at extreme temperatures.\"}, \"exp_004_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:31:40.554Z\", \"updated_at\": \"2026-05-17T02:57:35.012Z\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/analyze_exp004_v2_re_diagnostic.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004v2_re_diagnostic/\"}, \"completed_at\": \"2026-05-14T15:32:04.966Z\", \"hypothesis\": \"N-ablation v2 (N=4,8,16,32): tests how sample count affects signal ρ and selection F1. Validates N-scaling curve for structural vs surface signals under corrected pipeline.\"}, \"exp_009_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:36:47.946Z\", \"updated_at\": \"2026-05-17T02:57:32.655Z\", \"spec\": {\"command\": \"python3 code/exp_009_v2_stratification.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2 + exp_001_seed123_v2 + exp_008_re_n16_v2\", \"data_count\": 551, \"model_name\": \"analysis\", \"seed\": 42}, \"checkpoint_path\": \"output/exp_009_v2/results.json\", \"log_path\": \"output/exp_009_v2_run.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:37:18.311Z\", \"metrics\": {\"ner_seed42_global\": {\"sj_rho\": 0.431, \"fk_rho\": 0.325, \"logprob_rho\": 0.203, \"voting_conf_rho\": 0.475, \"em_rho\": 0.292}, \"ner_seed123_global\": {\"sj_rho\": 0.422, \"fk_rho\": 0.315, \"logprob_rho\": 0.226, \"voting_conf_rho\": 0.438, \"em_rho\": 0.299}, \"re_seed42_global\": {\"sj_rho\": 0.063, \"fk_rho\": 0.226, \"logprob_rho\": 0.4, \"voting_conf_rho\": 0.22, \"em_rho\": -0.132}, \"ner_seed_stability_max_delta\": 0.037, \"independent_proxies\": [\"sent_len\", \"ent_count\", \"type_diversity\"], \"inverted_u_ner\": \"not confirmed (ρ stable across independent proxies)\", \"inverted_u_re\": \"monotonic increase with complexity, not inverted-U\"}, \"hypothesis\": \"Capability stratification v2: corrected stratification with gold-filtering and extended to NER conditional analysis. Tests which instance subpopulations drive overall signal effectiveness.\"}, \"exp_016_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:39:07.501Z\", \"updated_at\": \"2026-05-17T02:57:30.726Z\", \"spec\": {\"command\": \"python code/exp_016_v2_ensemble.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2 + exp_001_seed123_v2 + exp_008_re_n16_v2\", \"data_count\": 551, \"model_name\": \"analysis_only\", \"seed\": 42, \"checkpoint_path\": \"output/exp_016_v2/\", \"log_path\": \"/tmp/exp016v2.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:39:34.478Z\", \"metrics\": {\"ner_conditional\": {\"n\": 529, \"best_single_signal_rho\": {\"soft_jaccard\": 0.4412}, \"best_combo_rho\": {\"sj+vc_a0.55\": 0.4552}, \"ensemble_auroc\": 0.7141, \"best_single_auroc\": {\"soft_jaccard\": 0.7166}, \"selection_f1\": {\"greedy\": 0.6442, \"logprob_best\": 0.6505, \"ensemble_best\": 0.6475, \"sj_best\": 0.6471, \"oracle\": 0.8442}}, \"re_conditional\": {\"n\": 397, \"best_single_signal_rho\": {\"voting_confidence\": 0.3849}, \"best_combo_rho\": {\"logprob+vc_a0.25\": 0.3936}, \"ensemble_auroc\": 0.6916, \"best_single_auroc\": {\"voting_confidence\": 0.7023}, \"selection_f1\": {\"greedy\": 0.403, \"logprob_best\": 0.4097, \"ensemble_best\": 0.4227, \"oracle\": 0.6306}}, \"re_full\": {\"ensemble_auroc\": 0.8608, \"best_single_auroc\": {\"voting_confidence\": 0.8248}}}, \"hypothesis\": \"Bootstrap significance v2: corrected bootstrap test for NER selection F1 gap with proper gold-filtering and multiple signals. Establishes which selection improvements are statistically significant.\"}, \"exp_001_seed456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:38:55.569Z\", \"updated_at\": \"2026-05-17T02:57:23.336Z\", \"spec\": {\"hypothesis\": \"NER/RE N=16 seed=456 robustness test, third seed for 3-seed stability\", \"plan_id\": \"exp-001\", \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed456_v2\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"metrics\": {\"full_rho_kappa_f1\": 0.3383, \"full_rho_sj_f1\": 0.2988, \"cond_rho_kappa_f1\": 0.233, \"cond_rho_sj_f1\": 0.3245, \"logprob_full_rho\": 0.3405, \"logprob_full_auroc\": 0.6694, \"logprob_cond_rho\": 0.0501, \"structural_gt_surface\": false}, \"note\": \"CRITICAL: Ran with --subtask joint instead of --subtask ner. seed42/seed123 v2 used --subtask ner. Results valid for joint-mode analysis but NOT comparable for NER 3-seed protocol. Need NER-only rerun.\", \"log_path\": \"output/exp_001_seed456_v2/run.log\", \"checkpoint_path\": \"output/exp_001_seed456_v2/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T17:12:14.682Z\", \"hypothesis\": \"SciERC joint NER+RE seed=456 v2: early pipeline version. Tests multi-seed stability of signal rankings on joint extraction task.\"}, \"exp_017_llama_conll_infer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:33:23.653Z\", \"updated_at\": \"2026-05-17T02:57:21.948Z\", \"spec\": {\"hypothesis\": \"LLaMA-3.1-8B CoNLL-2003 inference: cross-model cross-dataset validation of structural consistency signals\", \"plan_id\": \"exp-017\", \"parent\": \"exp_017_llama_conll\", \"command\": \"python code/run_llama_conll_infer.py\", \"server\": \"autodl-5090\", \"data_path\": \"conll2003 test\", \"data_count\": 3453, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 42, \"n_samples\": 8, \"temperature\": 1, \"description\": \"LLaMA CoNLL-2003 NER inference N=8 (cross-model + cross-dataset validation)\"}, \"metrics\": {\"greedy_f1\": 0.9266, \"oracle_f1\": 0.9443, \"oracle_headroom\": 0.0177, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"N\": 8, \"full\": {\"SJ_rho\": 0.4314, \"FK_rho\": 0.4277, \"logprob_rho\": 0.3072, \"EM_rho\": 0.4306, \"voting_conf_rho\": 0.4256, \"SJ_AUROC\": 0.7039, \"FK_AUROC\": 0.7026, \"logprob_AUROC\": 0.761, \"EM_AUROC\": 0.7046, \"voting_conf_AUROC\": 0.7088, \"SJ_ECE\": 0.1137, \"FK_ECE\": 0.1053, \"logprob_ECE\": 0.129, \"EM_ECE\": 0.1094, \"voting_conf_ECE\": 0.0949}, \"conditional\": {\"SJ_rho\": 0.4356, \"FK_rho\": 0.431, \"logprob_rho\": 0.3282, \"EM_rho\": 0.4403, \"voting_conf_rho\": 0.3743, \"SJ_AUROC\": 0.7225, \"FK_AUROC\": 0.7208, \"logprob_AUROC\": 0.8102, \"EM_AUROC\": 0.7257, \"voting_conf_AUROC\": 0.6989, \"SJ_ECE\": 0.0829, \"FK_ECE\": 0.0796, \"logprob_ECE\": 0.0922, \"EM_ECE\": 0.0754, \"voting_conf_ECE\": 0.0784}}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/samples.jsonl\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T17:55:33.476Z\", \"notes\": \"LLaMA CoNLL-2003 NER N=8 (not N=16, cost constraint: 3453 test instances). SJ ρ=0.431 > logprob ρ=0.307 (Δ=+0.124). ρ-AUROC dissociation: logprob AUROC=0.761 > SJ AUROC=0.704. All 4 structural signals ρ>0.42 vs logprob 0.31. Directly comparable to exp_002 (Qwen CoNLL N=8) and exp_007 (LLaMA SciERC N=8).\", \"hypothesis\": \"LLaMA CoNLL N=8 baseline inference: initial cross-model test on CoNLL before scaling to N=16. Establishes LLaMA can do CoNLL NER effectively.\"}, \"exp_003_wnut17_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:32:56.415Z\", \"updated_at\": \"2026-05-17T02:57:20.068Z\", \"spec\": {\"description\": \"WNUT-17 retrain: downsample gold-empty instances to ≤25%, fine-tune Qwen3-8B, inference N=16 T=1.0 with log-probs\", \"hypothesis\": \"After removing excess empty instances, structural consistency signals (SJ) will show stronger correlation on social media NER\", \"plan_id\": \"exp-003\", \"claim\": 1, \"model_name\": \"Qwen3-8B\", \"dataset\": \"WNUT-17 (downsampled)\", \"priority\": \"P0\", \"parent\": \"exp_003_ner_wnut17\", \"command\": \"CUDA_VISIBLE_DEVICES=1 llamafactory-cli train train_config_wnut17.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/wnut17/llmfactory_train_downsampled.json\", \"data_count\": 1637, \"seed\": 42, \"pid\": 92215, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/train_wnut17.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-lora\", \"downsampling\": \"empty instances 63.8% -> 25.0%, total 3394 -> 1637\", \"metrics\": {\"train_loss\": 0.105, \"eval_loss\": 0.0836, \"epochs\": 5, \"train_time_min\": 16.37, \"train_samples_per_sec\": 8.33}, \"note\": \"D045: Training succeeded (train_loss=0.105) but inference FAIL: 54% F1=0, SJ rho=0.062 (p=0.106). WNUT-17 abandoned — model capability insufficient on social media NER. Paper reports as Claim 3 (capability boundary) evidence.\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T18:11:36.559Z\", \"hypothesis\": \"WNUT-17 NER evaluation v2: tests signal effectiveness on noisy social media text. Hypothesis: structural signals remain effective on noisy, informal text with high entity variation.\"}, \"exp_001_seed456_v2_ner\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:13:00.414Z\", \"updated_at\": \"2026-05-17T02:57:18.227Z\", \"spec\": {\"hypothesis\": \"NER N=16 seed=456 robustness test (NER-only rerun, fixing subtask mismatch from exp_001_seed456_v2)\", \"plan_id\": \"exp-001\", \"parent\": \"exp_001_seed456_v2\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed456_v2_ner\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"data/scierc/processed_data\", \"metrics\": {\"sj_rho\": 0.384, \"structural_gt_surface\": true, \"structural_surface_delta\": 0.16}, \"log_path\": \"output/exp_001_seed456_v2_ner.log\", \"checkpoint_path\": \"output/exp_001_seed456_v2_ner/\"}, \"log_path\": \"output/exp_001_seed456_v2_ner.log\", \"pid\": 96161, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T17:52:01.372Z\", \"metrics\": {\"full\": {\"SJ\": {\"rho\": 0.384, \"auroc\": 0.711}, \"FK\": {\"rho\": 0.223, \"auroc\": 0.577}, \"logprob\": {\"rho\": 0.232, \"auroc\": 0.594}, \"EM\": {\"rho\": 0.316, \"auroc\": 0.768}, \"voting_conf\": {\"rho\": 0.411, \"auroc\": 0.712}}, \"conditional\": {\"SJ\": {\"rho\": 0.349, \"auroc\": 0.699}, \"FK\": {\"rho\": 0.157, \"auroc\": 0.561}, \"logprob\": {\"rho\": 0.171, \"auroc\": 0.576}, \"EM\": {\"rho\": 0.406, \"auroc\": 0.78}, \"voting_conf\": {\"rho\": 0.346, \"auroc\": 0.694}}, \"3seed_mean_SJ_rho_full\": 0.412, \"3seed_sd_SJ_rho_full\": 0.025, \"structural_beats_surface\": true, \"verdict\": \"MARGINAL\"}, \"hypothesis\": \"SciERC NER seed=456 v2: corrected pipeline rerun with gold-filtering. Part of multi-seed validation protocol for NER signal ranking stability.\"}, \"exp_009_v2_re_rerun\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:56:31.535Z\", \"updated_at\": \"2026-05-17T02:57:16.383Z\", \"spec\": {\"command\": \"python code/exp_009_v2_re_rerun.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_008_re_n16_v2/samples.jsonl\", \"data_count\": 397, \"model_name\": \"cpu_analysis\", \"seed\": 42, \"checkpoint_source\": \"exp_008_re_n16_v2\", \"checkpoint_path\": \"output/exp_009_v2_re_rerun/results.json\", \"log_path\": \"/tmp/re_rerun.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T18:56:58.168Z\", \"hypothesis\": \"Capability stratification v2 (RE rerun): corrected stratification analysis for RE with proper gold-filtering. Fixes early pipeline bug affecting RE quartile ρ values.\"}, \"exp_007_llama_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:31:44.366Z\", \"updated_at\": \"2026-05-17T02:57:12.521Z\", \"spec\": {\"hypothesis\": \"LLaMA SciERC N=16: cross-model N-scaling validation. If SJ rho increases from N=8 (0.363) to N=16, N-scaling is model-agnostic.\", \"plan_id\": \"exp-007\", \"parent\": \"exp_007_llama_inference\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_n16\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/llama3.1-8b-scierc-merged\", \"eval_data\": \"data/scierc/processed_data\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/exp_007_llama_n16/samples.jsonl\", \"log_path\": \"output/exp_007_llama_n16.log\", \"completed_at\": \"2026-05-14T19:03:39.163Z\", \"metrics\": {\"N\": 16, \"dataset\": \"scierc\", \"subtask\": \"ner\", \"n_instances\": 551, \"n_valid\": 529, \"n_conditional\": 478, \"greedy_f1\": 0.645, \"full\": {\"SJ_rho\": 0.3791, \"FK_rho\": 0.3081, \"logprob_rho\": 0.2041, \"EM_rho\": 0.3159, \"voting_conf_rho\": 0.4515, \"SJ_AUROC\": 0.717, \"FK_AUROC\": 0.6581, \"logprob_AUROC\": 0.5656, \"EM_AUROC\": 0.7686, \"voting_conf_AUROC\": 0.7266, \"SJ_ECE\": 0.1019, \"FK_ECE\": 0.1556, \"logprob_ECE\": 0.084, \"EM_ECE\": 0.1761, \"voting_conf_ECE\": 0.1365}, \"conditional\": {\"SJ_rho\": 0.3222, \"FK_rho\": 0.2182, \"logprob_rho\": 0.1286, \"EM_rho\": 0.3563, \"voting_conf_rho\": 0.3356, \"SJ_AUROC\": 0.7014, \"FK_AUROC\": 0.6392, \"logprob_AUROC\": 0.545, \"EM_AUROC\": 0.7708, \"voting_conf_AUROC\": 0.6988, \"SJ_ECE\": 0.1466, \"FK_ECE\": 0.1853, \"logprob_ECE\": 0.1141, \"EM_ECE\": 0.1887, \"voting_conf_ECE\": 0.2634}, \"n8_vs_n16_delta_rho_full\": {\"SJ\": 0.0161, \"FK\": -0.0185, \"logprob\": 0.0214, \"EM\": 0.0007, \"voting_conf\": 0.0184}}, \"hypothesis\": \"LLaMA SciERC N=16: cross-model NER signal evaluation at higher sample count. Tests if LLaMA shows same N-scaling benefit for structural signals as Qwen.\"}, \"exp_017_llama_conll_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:19:35.318Z\", \"updated_at\": \"2026-05-17T02:56:57.283Z\", \"spec\": {\"hypothesis\": \"LLaMA CoNLL N=16: complete the 2x2 matrix (model x dataset x N). If SJ N-scaling holds for LLaMA on CoNLL, the finding is fully cross-model cross-dataset.\", \"plan_id\": \"exp-017\", \"parent\": \"exp_017_llama_conll_infer\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"data_count\": 3453, \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_017_llama_conll_n16\", \"data_path\": \"data/conll2003\", \"pid\": 106997, \"n_samples\": 16, \"temperature\": 1, \"checkpoint_source\": \"checkpoints/llama3.1-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16/all_signals_report.json\"}, \"metrics\": {\"greedy_f1\": 0.9243, \"oracle_f1\": 0.9487, \"oracle_headroom\": 0.0244, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4642, \"SJ_AUROC\": 0.7391, \"SJ_ECE\": 0.1131, \"FK_rho\": 0.4566, \"FK_AUROC\": 0.736, \"FK_ECE\": 0.1071, \"logprob_rho\": 0.3058, \"logprob_AUROC\": 0.7594, \"logprob_ECE\": 0.1288, \"EM_rho\": 0.4613, \"EM_AUROC\": 0.7391, \"EM_ECE\": 0.1084, \"voting_conf_rho\": 0.4554, \"voting_conf_AUROC\": 0.7406, \"voting_conf_ECE\": 0.0844}, \"conditional\": {\"SJ_rho\": 0.4597, \"SJ_AUROC\": 0.7565, \"SJ_ECE\": 0.0846, \"FK_rho\": 0.4515, \"FK_AUROC\": 0.753, \"FK_ECE\": 0.0813, \"logprob_rho\": 0.3193, \"logprob_AUROC\": 0.8023, \"logprob_ECE\": 0.0921, \"EM_rho\": 0.4618, \"EM_AUROC\": 0.7589, \"EM_ECE\": 0.0757, \"voting_conf_rho\": 0.3978, \"voting_conf_AUROC\": 0.7287, \"voting_conf_ECE\": 0.0742}, \"best_of_n\": {\"greedy\": 0.9243, \"random_avg\": 0.9213, \"sj_best\": 0.9259, \"logprob_best\": 0.925, \"voting_conf_best\": 0.9268, \"oracle\": 0.9487}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0328, \"full_FK_rho_delta\": 0.0289, \"full_logprob_rho_delta\": -0.0014, \"full_EM_rho_delta\": 0.0307, \"full_voting_conf_rho_delta\": 0.0298, \"cond_SJ_rho_delta\": 0.0241, \"cond_FK_rho_delta\": 0.0205, \"cond_logprob_rho_delta\": -0.0089, \"cond_EM_rho_delta\": 0.0215, \"cond_voting_conf_rho_delta\": 0.0235}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T19:45:16.265Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=42 (original): cross-model validation on CoNLL. First evidence that structural>surface ranking generalizes from Qwen to LLaMA model family.\"}, \"exp_015_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:34:23.336Z\", \"updated_at\": \"2026-05-17T02:56:55.830Z\", \"spec\": {\"command\": \"python code/analyze_exp015_v2_metrics.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/ (10 datasets)\", \"data_count\": 9148, \"model_name\": \"Qwen3-8B + LLaMA (multi-model)\", \"seed\": \"42,123,456 (multi-seed)\", \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"/tmp/exp015_v2.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:34:56.741Z\", \"metrics\": {\"scierc_ner_avg\": {\"sj_auroc\": 0.7394, \"fk_auroc\": 0.6172, \"em_auroc\": 0.7873, \"voting_auroc\": 0.7367, \"logprob_auroc\": 0.5918}, \"scierc_re_avg\": {\"sj_auroc\": 0.6746, \"fk_auroc\": 0.5939, \"em_auroc\": 0.715, \"voting_auroc\": 0.7234, \"logprob_auroc\": 0.5849}}, \"hypothesis\": \"Metrics expansion v2: corrected evaluation with proper conditional filtering. Updates exp_015 with gold-filtered pipeline to fix RE conditional ρ values that used wrong filter criterion.\"}, \"exp_001_n16_seed456\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T12:10:30.350Z\", \"updated_at\": \"2026-05-17T02:56:53.526Z\", \"completed_at\": \"2026-05-14T12:28:38.721Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"success\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.6577, \"oracle_f1\": 0.8129, \"headroom\": 0.1553, \"rho_sj_full\": 0.3297, \"rho_fk_full\": 0.2578, \"rho_logprob_full\": 0.2866, \"rho_sj_cond\": 0.3394, \"rho_fk_cond\": 0.2721, \"rho_logprob_cond\": 0.2567, \"sj_beats_fk\": true, \"rho_advantage\": 0.0719}, \"re\": {\"greedy_f1\": 0.4312, \"oracle_f1\": 0.6737, \"headroom\": 0.2425, \"rho_sj_full\": 0.285, \"rho_fk_full\": 0.2372, \"rho_logprob_full\": 0.2626, \"rho_sj_cond\": 0.3525, \"rho_fk_cond\": 0.2614, \"rho_logprob_cond\": 0.1927, \"sj_beats_fk\": true, \"rho_advantage\": 0.0478}, \"verdict\": \"FAIL\"}}}, \"spec\": {\"hypothesis\": \"N=16 seed456 multi-seed robustness verification for SciERC NER+RE\", \"plan_id\": \"exp-001\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"seed\": 456, \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --output_dir output/exp001_n16_seed456 --collect_logprobs\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"174595\", \"log_path\": \"output/exp001_n16_seed456_run.log\", \"tmux_session\": \"exp_001_n16_seed456\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (inference-only)\", \"metrics\": {\"instance_count\": 551, \"n_valid\": 529, \"n_gold_empty\": 22, \"parse_rate\": 1, \"ner_greedy_f1\": 0.6617, \"ner_oracle_f1\": 0.8075, \"re_greedy_f1\": 0.4215, \"re_oracle_f1\": 0.4748, \"rho_sj_ner\": 0.4098, \"rho_fk_ner\": 0.2723, \"rho_vc_ner\": 0.4449, \"rho_em_ner\": 0.3363, \"rho_lp_ner\": 0.2415, \"rho_sj_re\": 0.2835, \"rho_fk_re\": 0.2929, \"auroc_sj_ner\": 0.6823, \"auroc_fk_ner\": 0.6179, \"auroc_vc_ner\": 0.6981, \"auroc_em_ner\": 0.649, \"auroc_lp_ner\": 0.5885, \"rho_note\": \"CORRECTED 2026-05-15: old values (rho_fk=0.3448,rho_sj=0.4134) included 22 gold-empty instances. Now uses gold-filtered pipeline (n=529).\"}, \"log_path\": \"output/exp001_n16_seed456_run.log\", \"hypothesis\": \"SciERC N=16 seed=456: early multi-seed validation of structural signal rankings at N=16 sample count. Establishes seed stability for SJ/FK/VC/EM ordering.\"}, \"exp_011_ood_scierc_to_conll\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:36:07.210Z\", \"updated_at\": \"2026-05-17T02:56:29.417Z\", \"spec\": {\"hypothesis\": \"SCS structural signals remain effective under domain shift (SciERC model on CoNLL data)\", \"plan_id\": \"exp-011\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"data_path\": \"data/conll2003\", \"seed\": 42, \"pid\": 179761, \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset conll2003 --data_dir data/conll2003 --subtask ner --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 42 --collect_logprobs --output_dir output/exp_011_ood_scierc_to_conll\", \"data_count\": 3500}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/exp_011_ood_scierc_to_conll/samples.jsonl\", \"log_path\": \"output/exp_011_ood_scierc_to_conll/report.json\", \"completed_at\": \"2026-05-15T11:47:47.953Z\", \"metrics\": {\"greedy_ner_f1\": 0.522, \"rho_vc\": 0.469, \"rho_sj\": 0.378, \"rho_em\": 0.3, \"rho_fk\": 0.285, \"rho_lp\": 0.246}, \"hypothesis\": \"Out-of-domain transfer: SciERC-trained model on CoNLL data. Tests if confidence signals work under partial schema overlap (SciERC has Organization/Person which overlap with CoNLL ORG/PER). Complement to exp_011_ood_conll_to_scierc.\"}, \"exp_qwen3_4b_scierc_finetune_v4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:26:25.512Z\", \"updated_at\": \"2026-05-17T02:56:24.418Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_scierc_4b.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"227123\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v4.log\", \"submitted_at\": \"2026-05-15T19:26:31.444Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"wall_clock_seconds\": 1668.8, \"gpu_hours\": 0.46}, \"conclusion\": \"success\", \"metrics\": {\"total_steps\": 585, \"completed_steps\": 585, \"best_checkpoint\": \"checkpoint-400\", \"best_eval_loss\": 0.0898, \"epochs\": 5}, \"checkpoint_path\": \"checkpoints/qwen3-4b-scierc-merged/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v4.log\", \"completed_at\": \"2026-05-15T19:54:20.255Z\", \"hypothesis\": \"Qwen3-4B SciERC LoRA fine-tune v4: training the smaller 4B model to complete the 2x2 scale matrix (4B×SciERC cell). Validates that fine-tuning convergence patterns hold across model scales.\"}, \"exp_011_ood_conll_to_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:36:08.325Z\", \"updated_at\": \"2026-05-17T02:56:14.242Z\", \"spec\": {\"hypothesis\": \"SCS structural signals remain effective under domain shift (CoNLL model on SciERC data, joint NER+RE)\", \"plan_id\": \"exp-011\", \"model_name\": \"qwen3-8b-conll2003-merged\", \"data_path\": \"data/scierc/processed_data\", \"seed\": 42, \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": 181723, \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --dataset scierc --data_dir data/scierc/processed_data --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 42 --collect_logprobs --output_dir output/exp_011_ood_conll_to_scierc\", \"data_count\": 551}, \"conclusion\": \"negative\", \"checkpoint_path\": \"output/exp_011_ood_conll_to_scierc/samples.jsonl\", \"log_path\": \"output/exp_011_ood_conll_to_scierc/report.json\", \"completed_at\": \"2026-05-15T11:50:21.969Z\", \"metrics\": {\"greedy_ner_f1\": 0.009, \"greedy_re_f1\": 0.001, \"avg_structural_rho\": -0.05, \"verdict\": \"FAIL\", \"reason\": \"schema_incompatibility\", \"direction\": \"CoNLL_model_to_SciERC_data\", \"sample_f1_pct_zero_ner\": 98.06, \"rho_sj_ner\": -0.186, \"rho_fk_ner\": -0.069, \"note\": \"Schema incompatibility (CoNLL PER/ORG/LOC/MISC vs SciERC Task/Method/Material) causes catastrophic failure. Cannot evaluate confidence signals.\"}, \"hypothesis\": \"Out-of-domain transfer test: CoNLL-trained model on SciERC data. Tests if confidence signals retain correlation with quality under severe schema mismatch (CoNLL PER/ORG/LOC/MISC vs SciERC Task/Method/Material).\"}, \"exp_freeform_seed789_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:24:26.805Z\", \"updated_at\": \"2026-05-17T02:56:11.818Z\", \"spec\": {\"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_seed789_v3.log\", \"checkpoint_path\": \"results/exp_freeform_ablation_seed789/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:30:51.048Z\", \"metrics\": {\"n_instances\": 551, \"n_samples\": 8, \"parse_rate_pct\": 100, \"elapsed_seconds\": 229.7, \"freeform_ner_selection_gap\": 0.0028, \"freeform_re_selection_gap\": 0.0219, \"freeform_lp_std\": 0.0183, \"freeform_lp_range\": 0.054908, \"freeform_tied_pct\": 59, \"re_lp_flip_positive\": true, \"variance_ratio_std\": 0.89, \"variance_ratio_range\": 0.88}, \"hypothesis\": \"Free-form SciERC seed=789 v3 (bugfix rerun): corrected version of free-form inference after fixing parsing/generation issues in v1/v2. Provides clean data point for 4-seed free-form analysis.\"}, \"exp_freeform_seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:38:29.851Z\", \"updated_at\": \"2026-05-17T02:56:09.888Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python run_freeform_inference.py --seed 789 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed789\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"216722\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_seed789.log\", \"submitted_at\": \"2026-05-15T18:58:46.406Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 92.2, \"gpu_hours\": 0.03}, \"notes\": \"Rerun with fixed seed-passing code on cuda:3. Original run was killed for GPU reallocation. Parse rate 100%, 227.5s elapsed. LP compression confirmed: tied_pct=59.0% (vs constrained 59.7%), variance_ratio=0.89x.\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:00:18.576Z\", \"metrics\": {\"inference\": {\"n_instances\": 551, \"n_samples\": 8, \"total_samples\": 4408, \"total_parsed\": 4408, \"parse_rate_pct\": 100, \"elapsed_seconds\": 227.5}, \"freeform\": {\"selection_ner\": {\"greedy\": 0.6205, \"selected\": 0.6232, \"gap\": 0.0027}, \"selection_re\": {\"greedy\": 0.2909, \"selected\": 0.31, \"gap\": 0.0191}, \"logprob_variance\": {\"mean_std\": 0.0183, \"mean_range\": 0.054908, \"tied_pct\": 59}, \"qe_ner\": {\"n\": 529, \"SJ\": {\"rho\": 0.393995, \"auroc\": 0.734474}, \"FK\": {\"rho\": 0.312292, \"auroc\": 0.794384}, \"LP\": {\"rho\": 0.247096, \"auroc\": 0.677824}, \"EM\": {\"rho\": 0.320383, \"auroc\": 0.527033}, \"VC\": {\"rho\": 0.420625, \"auroc\": 0.768111}}, \"qe_re\": {\"n\": 397, \"SJ\": {\"rho\": 0.201746, \"auroc\": 0.574388}, \"FK\": {\"rho\": 0.2202, \"auroc\": 0.633014}, \"LP\": {\"rho\": 0.295765, \"auroc\": 0.687067}, \"EM\": {\"rho\": 0.103633, \"auroc\": 0.474737}, \"VC\": {\"rho\": 0.306868, \"auroc\": 0.642197}}}, \"constrained_ref\": {\"selection_ner\": {\"greedy\": 0.6182, \"selected\": 0.6241, \"gap\": 0.0059}, \"selection_re\": {\"greedy\": 0.2913, \"selected\": 0.2845, \"gap\": -0.0068}, \"logprob_variance\": {\"mean_std\": 0.020589, \"mean_range\": 0.062305, \"tied_pct\": 59.7}}, \"comparison\": {\"variance_ratio_std\": 0.89, \"variance_ratio_range\": 0.88, \"tied_reduction_pp\": 0.7}}, \"hypothesis\": \"Free-form SciERC seed=789: multi-seed replication of free-form ablation. Validates LP compression persistence and structural signal robustness across sampling seeds under unconstrained generation.\"}, \"exp_freeform_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:14:48.842Z\", \"updated_at\": \"2026-05-17T02:56:09.256Z\", \"spec\": {\"hypothesis\": \"Multi-seed free-form ablation (seed=456): verify RE LP flip and NER gap stability\", \"command\": \"python run_freeform_inference.py --seed 456 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed456\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"gpu\": \"cuda:2\", \"tmux_session\": \"exp_freeform_seed456\", \"log_path\": \"results/exp_freeform_ablation_seed456/run_summary.json\", \"checkpoint_path\": \"results/exp_freeform_ablation_seed456\"}, \"metrics\": {\"inference\": {\"n_instances\": 551, \"n_samples\": 8, \"total_samples\": 4408, \"total_parsed\": 4407, \"parse_rate_pct\": 99.98, \"elapsed_seconds\": 232.4}, \"freeform\": {\"selection_ner\": {\"greedy\": 0.6198, \"selected\": 0.6205, \"gap\": 0.0007}, \"selection_re\": {\"greedy\": 0.2908, \"selected\": 0.3108, \"gap\": 0.02}, \"logprob_variance\": {\"mean_std\": 0.018631, \"mean_range\": 0.056792, \"tied_pct\": 58.4}, \"qe_ner\": {\"n\": 529, \"SJ\": {\"rho\": 0.378498, \"auroc\": 0.707769}, \"FK\": {\"rho\": 0.286163, \"auroc\": 0.754779}, \"LP\": {\"rho\": 0.227089, \"auroc\": 0.672081}, \"EM\": {\"rho\": 0.319997, \"auroc\": 0.47789}, \"VC\": {\"rho\": 0.416853, \"auroc\": 0.756543}}, \"qe_re\": {\"n\": 397, \"SJ\": {\"rho\": 0.211331, \"auroc\": 0.572335}, \"FK\": {\"rho\": 0.259074, \"auroc\": 0.652998}, \"LP\": {\"rho\": 0.306382, \"auroc\": 0.70134}, \"EM\": {\"rho\": 0.1043, \"auroc\": 0.461641}, \"VC\": {\"rho\": 0.301507, \"auroc\": 0.628873}}}, \"constrained_ref\": {\"selection_ner\": {\"greedy\": 0.6182, \"selected\": 0.6241, \"gap\": 0.0059}, \"selection_re\": {\"greedy\": 0.2913, \"selected\": 0.2845, \"gap\": -0.0068}, \"logprob_variance\": {\"mean_std\": 0.020589, \"mean_range\": 0.062305, \"tied_pct\": 59.7}}, \"comparison\": {\"variance_ratio_std\": 0.9, \"variance_ratio_range\": 0.91, \"tied_reduction_pp\": 1.3}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:12:29.413Z\", \"hypothesis\": \"Free-form SciERC seed=456: multi-seed replication of free-form ablation. Validates LP compression persistence and structural signal robustness across sampling seeds under unconstrained generation.\"}, \"exp_freeform_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:14:47.765Z\", \"updated_at\": \"2026-05-17T02:56:06.903Z\", \"spec\": {\"hypothesis\": \"Multi-seed free-form ablation (seed=123): verify RE LP flip and NER gap stability\", \"command\": \"python run_freeform_inference.py --seed 123 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed123\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": \"cuda:1\", \"tmux_session\": \"exp_freeform_seed123\", \"log_path\": \"results/exp_freeform_ablation_seed123/run_summary.json\", \"checkpoint_path\": \"results/exp_freeform_ablation_seed123\"}, \"metrics\": {\"inference\": {\"n_instances\": 551, \"n_samples\": 8, \"total_samples\": 4408, \"total_parsed\": 4406, \"parse_rate_pct\": 99.95, \"elapsed_seconds\": 228.1}, \"freeform\": {\"selection_ner\": {\"greedy\": 0.6194, \"selected\": 0.6222, \"gap\": 0.0028}, \"selection_re\": {\"greedy\": 0.2874, \"selected\": 0.305, \"gap\": 0.0176}, \"logprob_variance\": {\"mean_std\": 0.019881, \"mean_range\": 0.059864, \"tied_pct\": 57.7}, \"qe_ner\": {\"n\": 529, \"SJ\": {\"rho\": 0.384214, \"auroc\": 0.748728}, \"FK\": {\"rho\": 0.323956, \"auroc\": 0.766039}, \"logprob\": {\"rho\": 0.217297, \"auroc\": 0.701657}, \"EM\": {\"rho\": 0.326887, \"auroc\": 0.52533}, \"voting_conf\": {\"rho\": 0.407893, \"auroc\": 0.799676}}, \"qe_re\": {\"n\": 397, \"SJ\": {\"rho\": 0.272776, \"auroc\": 0.614056}, \"FK\": {\"rho\": 0.314429, \"auroc\": 0.678534}, \"logprob\": {\"rho\": 0.309673, \"auroc\": 0.70414}, \"EM\": {\"rho\": 0.137216, \"auroc\": 0.487342}, \"voting_conf\": {\"rho\": 0.316667, \"auroc\": 0.647442}}}, \"constrained_ref\": {\"selection_ner\": {\"greedy\": 0.6182, \"selected\": 0.6241, \"gap\": 0.0059}, \"selection_re\": {\"greedy\": 0.2913, \"selected\": 0.2845, \"gap\": -0.0068}}, \"comparison\": {\"variance_ratio_std\": 0.97, \"variance_ratio_range\": 0.96, \"tied_reduction_pp\": 2}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:29:48.939Z\", \"hypothesis\": \"Free-form SciERC seed=123: multi-seed replication of free-form ablation. Validates LP compression persistence and structural signal robustness across sampling seeds under unconstrained generation.\"}, \"exp_009_capability_stratification\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:59:24.201Z\", \"updated_at\": \"2026-05-17T02:56:02.685Z\", \"spec\": {\"command\": \"python code/exp009_stratification_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp001_n16_seed42 + output/exp008_re_n16 + output/exp002_conll2003\", \"data_count\": 4555, \"model_name\": \"analysis_only\", \"seed\": 42}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/exp009_stratification_results.json\", \"log_path\": \"/tmp/exp009.log\", \"completed_at\": \"2026-05-14T14:59:46.463Z\", \"metrics\": {\"scierc_ner\": {\"n\": 551, \"sj_rho_overall\": 0.398, \"by_greedy_f1\": {\"hard_0_25_sj_rho\": 0.159, \"med_low_sj_rho\": 0.139, \"med_high_sj_rho\": 0.09, \"easy_sj_rho\": 0.23}, \"by_sent_len\": {\"Q1_sj_rho\": 0.461, \"Q2_sj_rho\": 0.401, \"Q3_sj_rho\": 0.296, \"Q4_sj_rho\": 0.382}, \"by_ent_count\": {\"0_sj_rho\": 0.689, \"1_2_sj_rho\": 0.415, \"3_5_sj_rho\": 0.353, \"6plus_sj_rho\": 0.547}}, \"scierc_re\": {\"n\": 551, \"by_greedy_f1\": {\"hard_0_25_sj_rho\": -0.043, \"easy_sj_rho\": 0.21}, \"by_sent_len\": {\"Q1_sj_rho\": 0.447, \"Q4_sj_rho\": 0.54}, \"by_rel_count\": {\"0_sj_rho\": 0.62, \"1_2_sj_rho\": 0.275, \"6plus_sj_rho\": 0.527}}, \"conll_ner\": {\"n\": 3453, \"by_sent_len\": {\"Q1_sj_rho\": 0.334, \"Q3_sj_rho\": 0.518}}, \"proxy_independence\": {\"scierc_ner_f1_vs_slen\": -0.021, \"scierc_ner_f1_vs_ecnt\": 0.007, \"scierc_re_f1_vs_slen\": -0.147}}, \"notes\": \"Registry metrics are PRE-gold-filter (n=551). Paper uses exp_009_v2_re_rerun (gold-filtered n=397): RE Q1_sj_rho=0.110, Q4_sj_rho=0.473. Registry values (Q1=0.447, Q4=0.540) are SUPERSEDED.\", \"hypothesis\": \"Capability stratification analysis: test if SJ signal effectiveness varies with instance difficulty (greedy F1 quartiles), sentence length, and entity/relation count. Identifies which instance subpopulations benefit most from structural consistency signals.\"}, \"exp_023_lora_rank8\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:29:59.501Z\", \"updated_at\": \"2026-05-17T02:55:50.540Z\", \"spec\": {\"hypothesis\": \"LoRA rank=8 ablation: does reducing rank from 32 to 8 significantly affect correlation-selection patterns?\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/llmfactory_train.json\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_002_v2\", \"method\": \"LoRA r=8 alpha=16, 5 epochs, batch=2 grad_accum=8 gradient_checkpointing=true\", \"gpu\": \"cuda:2\", \"pid\": 288382, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp023_rank8_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora-rank8\", \"command\": \"CUDA_VISIBLE_DEVICES=2 llamafactory-cli train train_config_rank8.yaml\", \"trainable_params\": \"21.8M\", \"total_steps\": 585, \"estimated_runtime\": \"26min\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.1018, \"eval_loss\": 0.0776, \"train_runtime\": \"28m45s\", \"ner_full\": {\"n\": 529, \"greedy_f1\": 0.6397, \"oracle_f1\": 0.7998, \"oracle_headroom\": 0.1601, \"degeneracy_rate\": 0.072, \"SJ_rho\": 0.3649, \"FK_rho\": 0.2838, \"VC_rho\": 0.394, \"EM_rho\": 0.2562, \"LP_rho\": 0.2105, \"SJ_auroc\": 0.689, \"FK_auroc\": 0.6002, \"VC_auroc\": 0.6886, \"EM_auroc\": 0.7265, \"LP_auroc\": 0.6054, \"sel_SJ\": 0.6306, \"sel_FK\": 0.6265, \"sel_VC\": 0.5919, \"sel_EM\": 0.6073, \"sel_LP\": 0.635}, \"ner_cond\": {\"n\": 477, \"SJ_rho\": 0.3056, \"FK_rho\": 0.1452, \"VC_rho\": 0.3191, \"EM_rho\": 0.3558, \"LP_rho\": 0.169}, \"re_full\": {\"n\": 397, \"greedy_f1\": 0.3712, \"oracle_f1\": 0.609, \"oracle_headroom\": 0.2378, \"degeneracy_rate\": 0.217, \"SJ_rho\": 0.2244, \"FK_rho\": 0.3448, \"VC_rho\": 0.3617, \"EM_rho\": 0.068, \"LP_rho\": 0.2737, \"SJ_auroc\": 0.7092, \"FK_auroc\": 0.6469, \"VC_auroc\": 0.7533, \"EM_auroc\": 0.7306, \"LP_auroc\": 0.6325, \"sel_SJ\": 0.3584, \"sel_FK\": 0.3498, \"sel_VC\": 0.3715, \"sel_EM\": 0.3291, \"sel_LP\": 0.3606}, \"re_cond\": {\"n\": 242, \"SJ_rho\": 0.3601, \"FK_rho\": 0.2343, \"VC_rho\": 0.3703, \"EM_rho\": 0.4613, \"LP_rho\": 0.1809}}, \"completed_at\": \"2026-05-16T11:22:34.576Z\", \"hypothesis\": \"LoRA rank=8 ablation on SciERC: test if reduced model capacity (rank 8 vs 32) changes signal effectiveness ranking or correlation-selection gap pattern. Verifies findings are not rank-specific artifacts.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_022_seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:08:27.375Z\", \"updated_at\": \"2026-05-17T02:55:49.870Z\", \"hypothesis\": \"3rd seed SciERC inference (seed=789) with ft_002_v2 (Qwen3-8B). N=8, T=1.0, joint NER+RE, logprobs collected. Complements seed42 (exp_012_rerun_1024) and seed123/456 for multi-seed analysis.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 789 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_022_seed789/\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-8B (qwen3-8b-scierc-merged-v2)\", \"seed\": 789, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_022_seed789/run.log\", \"gpu\": \"cuda:0\", \"pid\": 286743, \"account\": \"root\", \"backend\": \"tmux\", \"tmux_session\": \"exp_022_seed789\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T14:25:17.461Z\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_025_n32\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T13:38:26.420Z\", \"updated_at\": \"2026-05-17T02:55:46.212Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_025_n32/run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T14:25:39.849Z\", \"metrics\": {\"n_samples\": 32, \"degeneracy_pct\": 4, \"lp_range\": 0.0781, \"oracle_f1\": 0.8412, \"greedy_f1\": 0.6615, \"oracle_gap\": 0.1797, \"selection_f1_lp_delta\": 0.54, \"selection_f1_sj_delta\": 0.16, \"selection_f1_fk_delta\": 0.6, \"selection_f1_em_delta\": 0.68, \"selection_f1_vc_delta\": -5.21, \"best_signal\": \"EM\", \"best_delta\": 0.68, \"metric_space\": \"micro_f1_filtered_529inst\", \"note\": \"corrected via n_ablation_fixed.py, greedy from inst['greedy'] field\"}, \"hypothesis\": \"N=32 sample ablation on SciERC: test if increasing samples from 8→32 reduces degeneracy and improves selection F1, particularly for structural signals. Validates whether sample count is the bottleneck for signal effectiveness.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_021_fewnerd_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T16:33:44.079Z\", \"updated_at\": \"2026-05-17T02:55:45.560Z\", \"hypothesis\": \"Full Few-NERD LoRA fine-tune (rank=32, α=64, 3 epochs) on SUPERVISED coarse 8-type NER (131k train). 4-GPU DDP on autodl-5090. Post-training: N=8 inference on full test set, T=1.0, seed=42, collect logprobs for SCS metrics.\", \"spec\": {\"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"gpu_count\": 4, \"training_mode\": \"DDP\", \"checkpoint_path\": \"output/exp_021_fewnerd_full/checkpoint-6177\", \"log_path\": \"output/exp_021_inference/\"}, \"conclusion\": \"success\", \"metrics\": {\"total_steps\": 6177, \"train_loss\": 0.048, \"eval_loss\": 0.0275, \"train_runtime\": \"3h57m\", \"epochs\": 3, \"final_checkpoint\": \"output/exp_021_fewnerd_full/checkpoint-6177\", \"adapter_path\": \"output/exp_021_fewnerd_full/adapter_model.safetensors\", \"inference_instances\": 37648, \"inference_filtered\": 32565, \"inference_n_samples\": 8, \"greedy_macro_f1\": 0.7478, \"oracle_macro_f1\": 0.8719, \"headroom\": 0.124, \"zero_f1_rate\": 0.119, \"degeneracy_rate\": 0.101, \"lp_within_range_mean\": 0.0879, \"lp_within_range_median\": 0.0662, \"lp_global_rho\": 0.4215, \"lp_cond_rho\": 0.4225, \"sj_global_rho\": 0.3002, \"sj_cond_rho\": 0.2937, \"fk_global_rho\": 0.3132, \"fk_cond_rho\": 0.3093, \"em_global_rho\": 0.2871, \"em_cond_rho\": 0.271, \"vc_global_rho\": 0.3858, \"vc_cond_rho\": 0.3234, \"lp_selection_delta_pp\": 1.36, \"vc_selection_delta_pp\": -1.79, \"sj_selection_delta_pp\": -2.14, \"fk_selection_delta_pp\": -2.26, \"em_selection_delta_pp\": -3.85, \"lp_bootstrap_ci_95_pp\": [1.18, 1.53], \"lp_sample_auroc\": 0.5782, \"vc_sample_auroc\": 0.5354, \"fk_sample_auroc\": 0.521, \"sj_sample_auroc\": 0.5197, \"em_sample_auroc\": 0.5137, \"scenario\": \"A_partial\", \"note\": \"Full analysis (gold-filtered n=32565). Prior simplified analysis used unfiltered data with different metrics.\"}, \"completed_at\": \"2026-05-16T22:04:16.683Z\", \"parent\": \"exp_020_fewnerd_smoke\"}, \"exp_015_metrics_expansion\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:47:36.569Z\", \"updated_at\": \"2026-05-17T02:55:35.391Z\", \"spec\": {\"hypothesis\": \"Comprehensive evaluation of all 5 confidence signals with extended metrics\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"exp_012_logprob_baseline\", \"method\": \"CPU-only analysis: 6 metrics x 5 signals x 2 subtasks (NER+RE)\", \"command\": \"python code/analyze_exp015_metrics_expansion.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp015_metrics_expansion\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:22:32.661Z\", \"metrics\": {\"data_source\": \"exp_012_logprob/samples_with_logprobs.jsonl\", \"config\": \"N=8, T=1.0, seed=42, model=qwen3-8b-scierc-merged-v2\", \"ner\": {\"n_valid\": 529, \"n_cond\": 501, \"voting_rho_full\": 0.5018, \"voting_rho_cond\": 0.4497, \"voting_auroc\": 0.7279, \"voting_tau\": 0.3766, \"sj_rho_full\": 0.3565, \"sj_rho_cond\": 0.412, \"sj_auroc\": 0.6656, \"sj_tau\": 0.2658, \"em_rho_full\": 0.2566, \"em_rho_cond\": 0.3427, \"em_auroc\": 0.623, \"em_tau\": 0.1924, \"fk_rho_full\": 0.2651, \"fk_rho_cond\": 0.306, \"fk_auroc\": 0.6243, \"fk_tau\": 0.2027, \"logprob_rho_full\": 0.1396, \"logprob_rho_cond\": 0.1627, \"logprob_auroc\": 0.5585, \"logprob_tau\": 0.1006}, \"re\": {\"n_valid\": 397, \"n_cond\": 296, \"voting_rho_full\": 0.4217, \"voting_rho_cond\": 0.463, \"voting_auroc\": 0.7162, \"voting_tau\": 0.327, \"sj_rho_full\": 0.2112, \"sj_rho_cond\": 0.3683, \"sj_auroc\": 0.5816, \"sj_tau\": 0.1619, \"em_rho_full\": 0.1002, \"em_rho_cond\": 0.3607, \"em_auroc\": 0.5036, \"em_tau\": 0.0839, \"fk_rho_full\": 0.2528, \"fk_rho_cond\": 0.3168, \"fk_auroc\": 0.6308, \"fk_tau\": 0.1967, \"logprob_rho_full\": 0.2467, \"logprob_rho_cond\": 0.1457, \"logprob_auroc\": 0.6354, \"logprob_tau\": 0.1808}, \"diagnosis\": \"Unified 5-signal evaluation on single data source. Voting leads NER full (ρ=0.502), SJ retains strength in NER cond (ρ=0.412). All structural signals beat logprob on NER. RE: voting leads both full and cond.\"}, \"notes\": \"RE logprob_rho_cond=0.1457 uses WRONG conditional filter (any sample F1>0, n=331). Correct value: 0.0112 from exp_012_rerun_1024 (greedy_f1>0, n=238). This entry's RE cond values are DEPRECATED.\", \"hypothesis\": \"Unified 5-signal evaluation (SJ/FK/EM/VC/LP) on single canonical data source (exp_012 logprobs). Establishes complete signal ranking with ρ, AUROC, and τ metrics for both NER and RE under consistent conditions.\"}, \"exp_020_fewnerd_smoke\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:29:25.272Z\", \"updated_at\": \"2026-05-16T16:33:59.109Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/ft_fewnerd_smoke\", \"log_path\": \"checkpoints/fewnerd_train.log\"}, \"hypothesis\": \"1-epoch LoRA (r16) fine-tune Qwen3-8B on Few-NERD INTRA coarse 8-type (131k train), then N=8 T=1.0 pilot inference on 200 test instances. Re-started training 2026-05-16 18:29 CST on cuda:1, PID 288683. ETA ~22:55 CST.\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.031, \"total_steps\": 8236, \"training_time\": \"5h54m\", \"pilot_greedy_f1\": 0.8037, \"pilot_instances\": 200, \"merged_model_path\": \"checkpoints/qwen3-8b-fewnerd-merged\"}, \"completed_at\": \"2026-05-16T16:33:59.109Z\"}, \"exp_vc_lp_cascade_selection\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:44:02.658Z\", \"updated_at\": \"2026-05-16T06:31:26.755Z\", \"hypothesis\": \"VC-filtered LP selection cascade: test if combining VC (pre-filter) + LP (rank) improves selection F1 over single-signal selection. Addresses SF3 reviewer suggestion. Pure analysis on existing data.\", \"conclusion\": \"killed\", \"spec\": {\"command\": \"N/A - cancelled before execution\", \"server\": \"N/A\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"completed_at\": \"2026-05-16T06:31:26.755Z\"}, \"exp_tacred_re_benchmark\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:43:59.002Z\", \"updated_at\": \"2026-05-16T06:31:25.273Z\", \"hypothesis\": \"TACRED RE benchmark: replicate SciERC RE experiment flow on second RE dataset. Verify correlation-selection gap generalizes beyond SciERC. D104 highest priority — addresses R11 MF1 consensus weakness.\", \"conclusion\": \"killed\", \"spec\": {\"command\": \"N/A - cancelled before execution\", \"server\": \"N/A\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"completed_at\": \"2026-05-16T06:31:25.273Z\"}, \"exp_vc_quartile_analysis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:48:35.263Z\", \"updated_at\": \"2026-05-16T05:00:36.736Z\", \"hypothesis\": \"VC quartile stratification: split instances by VC score into Q1-Q4, compute LP selection F1 per quartile. Test if LP selection ability recovers in high-VC instances. Addresses SF3.\", \"spec\": {\"command\": \"python vc_quartile_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_rerun_1024/samples.jsonl + output/exp_002_conll_n8_seed42/samples.jsonl\", \"data_count\": 3682, \"model_name\": \"analysis_only (Qwen3-8B data)\", \"seed\": 42}, \"conclusion\": \"success\", \"checkpoint_path\": \"artifacts/vc_quartile_analysis/results.json\", \"log_path\": \"artifacts/vc_quartile_analysis/report.md\", \"completed_at\": \"2026-05-16T05:00:30.439Z\", \"metrics\": {\"scierc_ner\": {\"Q1_lp_delta\": 0.016, \"Q2_lp_delta\": -0.006, \"Q3_lp_delta\": 0.02, \"Q4_lp_delta\": -0.004, \"Q4_mean_vc\": 0.921, \"Q1_headroom\": 0.169, \"Q4_headroom\": 0.048, \"overall_lp_delta\": 0.006, \"n\": 529}, \"scierc_re\": {\"Q1_lp_delta\": -0.036, \"Q2_lp_delta\": -0.021, \"Q3_lp_delta\": -0.022, \"Q4_lp_delta\": 0.04, \"Q4_mean_vc\": 0.894, \"Q1_headroom\": 0.211, \"Q4_headroom\": 0.145, \"overall_lp_delta\": -0.009, \"n\": 397}, \"conll_ner\": {\"Q1_lp_delta\": -0.037, \"Q2_lp_delta\": -0.005, \"Q3_lp_delta\": 0, \"Q4_lp_delta\": 0, \"overall_lp_delta\": -0.01, \"n\": 2756, \"note\": \"Q3/Q4 degenerate (VC=1.0, all samples identical)\"}, \"conclusion\": \"VC stratification does not solve LP compression for NER. RE Q4 is only exception (+0.040).\"}}, \"exp_llama3b_scierc_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:45:23.638Z\", \"updated_at\": \"2026-05-16T03:59:26.005Z\", \"hypothesis\": \"Cross-family scale ablation: LLaMA 3.2-3B on SciERC NER. Verify correlation-selection gap generalizes across model families AND scales. Compare with LLaMA 8B results.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.2-3b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/review_round9_experiments/llama3b_scierc/\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"LLaMA-3.2-3B-Instruct (LoRA r=32 SciERC fine-tuned)\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/llama3.2-3b-scierc-merged\", \"log_path\": \"output/review_round9_experiments/llama3b_scierc/inference.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:59:16.198Z\", \"metrics\": {\"ner_full\": {\"SJ_rho\": 0.3754, \"FK_rho\": 0.2676, \"LP_rho\": 0.2662, \"EM_rho\": 0.3341, \"VC_rho\": 0.4602, \"SJ_auroc\": 0.7383, \"FK_auroc\": 0.6714, \"LP_auroc\": 0.633, \"EM_auroc\": 0.7763, \"VC_auroc\": 0.7429, \"n\": 529}, \"ner_cond\": {\"SJ_rho\": 0.3445, \"FK_rho\": 0.2125, \"LP_rho\": 0.2099, \"EM_rho\": 0.3952, \"VC_rho\": 0.3815, \"SJ_auroc\": 0.7292, \"FK_auroc\": 0.66, \"LP_auroc\": 0.6156, \"EM_auroc\": 0.7822, \"VC_auroc\": 0.7222, \"n\": 476}, \"greedy_f1\": 0.6267, \"oracle_f1\": 0.763, \"oracle_headroom\": 0.1363, \"selection_f1_SJ\": 0.6328, \"selection_f1_VC\": 0.6113, \"selection_f1_FK\": 0.6295, \"selection_f1_EM\": 0.6174, \"selection_f1_LP\": 0.6279, \"n_gold_empty\": 22, \"structural_beats_surface\": true, \"rho_advantage_SJ_over_FK\": 0.1078}}, \"exp_freeform_conll_4seed\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:45:17.133Z\", \"updated_at\": \"2026-05-16T03:04:49.550Z\", \"hypothesis\": \"Free-form CoNLL NER 4-seed ablation: verify LP compression is cross-dataset intrinsic (not SciERC-specific). 4 seeds × N=8, T=1.0 on CoNLL, compare LP range distribution with constrained decoding.\", \"spec\": {\"command\": \"python run_freeform_conll.py --seed {42,123,456,789} --gpu {0,1,2,3} --n_samples 8 --temperature 1.0\", \"server\": \"autodl-4x5090\", \"data_path\": \"data/conll2003/test.jsonl\", \"data_count\": 3453, \"model_name\": \"checkpoints/qwen3-8b-conll2003-merged\", \"seed\": \"42,123,456,789\"}, \"checkpoint_path\": \"N/A (inference-only experiment)\", \"log_path\": \"output/review_round9_experiments/freeform_conll/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:04:40.278Z\", \"metrics\": {\"greedy_f1\": \"0.9035±0.0004\", \"oracle_f1\": \"0.9460±0.0023\", \"lp_range_median\": \"0.0581±0.0072\", \"rho_sj\": \"0.4606±0.0188\", \"rho_fk\": \"0.4372±0.0209\", \"rho_em\": \"0.4714±0.0168\", \"rho_vc\": \"0.4606±0.0138\", \"rho_lp\": \"0.3262±0.0120\", \"sel_f1_sj\": \"0.8994±0.0014\", \"sel_f1_vc\": \"0.9006±0.0026\", \"sel_f1_lp\": \"0.8958±0.0009\", \"seeds\": [42, 123, 456, 789], \"n_samples\": 8, \"temperature\": 1, \"instances\": 2756, \"gold_empty_filtered\": 697}}, \"exp_qwen3_4b_conll_merge_inference_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:42:42.107Z\", \"updated_at\": \"2026-05-15T20:07:12.593Z\", \"hypothesis\": \"CoNLL 4B checkpoint-4200 (best from resume training) merge + SCS inference. Replaces v1 which used checkpoint-3800 merged model. Cross-scale evidence for correlation-selection gap.\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-conll2003-merged-ckpt4200 --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_conll_merge_inference_v2\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-4B (LoRA merged, ckpt-4200)\", \"seed\": 42, \"checkpoint_source\": \"exp_qwen3_4b_conll_finetune_resume (checkpoint-4200)\"}, \"checkpoint_path\": \"N/A - duplicate\", \"log_path\": \"N/A - duplicate\", \"conclusion\": \"killed\", \"notes\": \"Superseded by exp_qwen3_4b_conll_scs_inference_v2. Output was empty (dead experiment), functionally duplicate.\", \"completed_at\": \"2026-05-15T20:03:47.431Z\"}, \"exp_qwen3_4b_scierc_merge_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:42:43.332Z\", \"updated_at\": \"2026-05-15T20:04:15.433Z\", \"hypothesis\": \"SciERC 4B best checkpoint merge + SCS inference. Complete 2x2 scale matrix (4B SciERC cell). Cross-scale + cross-task evidence for correlation-selection gap.\", \"checkpoint_path\": \"N/A - superseded\", \"log_path\": \"N/A - superseded\", \"conclusion\": \"killed\", \"notes\": \"Superseded by exp_qwen3_4b_scierc_scs_inference. Never launched (stuck in PREPARING). Killed during registry cleanup.\", \"completed_at\": \"2026-05-15T20:04:15.433Z\"}, \"exp_qwen3_4b_scierc_finetune_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:24:45.518Z\", \"updated_at\": \"2026-05-15T19:39:04.438Z\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scierc_4b.yaml\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"226610\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v3.log\", \"submitted_at\": \"2026-05-15T19:24:55.461Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"wall_clock_seconds\": 849.0, \"gpu_hours\": 0.24}, \"conclusion\": \"failed\", \"notes\": \"OOM on cuda:2 — freeform inference (seed789, 8B) 占满 GPU 2。未实际训练。重启为 v4 on cuda:0。\", \"completed_at\": \"2026-05-15T19:39:04.438Z\"}, \"exp_qwen3_4b_conll_finetune_resume\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:38:19.388Z\", \"updated_at\": \"2026-05-15T19:38:43.468Z\", \"hypothesis\": \"CoNLL 4B NER LoRA fine-tune resume from checkpoint-3800. Cross-scale evidence for correlation-selection gap.\", \"spec\": {\"hypothesis\": \"CoNLL2003 NER LoRA fine-tune with Qwen3-4B, resume from checkpoint-3800 to complete 5 epochs\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_conll2003_4b_resume.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"data_path\": \"data/conll2003/llmfactory_train.json\", \"data_count\": 14042, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"resume_from\": \"checkpoint-3800\", \"lora_rank\": 32, \"lora_alpha\": 64, \"num_train_epochs\": 5, \"learning_rate\": 0.0002, \"batch_size\": \"2 x 8 grad_accum\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-lora\", \"best_checkpoint\": \"checkpoint-4200\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-lora/trainer_state.json\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.001136, \"eval_loss\": 0.0225, \"best_global_step\": 4200, \"best_metric_eval_loss\": 0.0225, \"total_steps\": 4390, \"epochs\": 5, \"train_runtime_sec\": 1185.8, \"train_samples_per_second\": 59.2, \"resumed_from_step\": 3800}, \"completed_at\": \"2026-05-15T19:38:43.468Z\"}, \"exp_qwen3_4b_scierc_finetune_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:03:49.204Z\", \"updated_at\": \"2026-05-15T19:24:32.466Z\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scierc_4b.yaml\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": \"219830\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v2.log\", \"submitted_at\": \"2026-05-15T19:05:31.524Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 1861, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"D096\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-scierc-lora/\", \"wall_clock_seconds\": 1122.6, \"gpu_hours\": 0.31}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T19:24:14.124Z\", \"notes\": \"PID 219830 已死，仅完成 step 10，无 checkpoint。需彻底重启。\"}, \"exp_qwen3_4b_conll_finetune\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-15T17:18:35.501Z\", \"updated_at\": \"2026-05-15T19:10:24.822Z\", \"hypothesis\": \"Scale ablation: Qwen3-4B CoNLL NER LoRA fine-tune to provide cross-scale evidence (vs 8B). Verify correlation-selection gap, SJ>FK ordering, and LP compression generalize across model scale.\", \"reproduce\": {\"finished_at\": \"2026-05-15T18:45:42.215Z\"}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-15T18:45:43.672Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:45:49.686191+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli train train_config_conll2003_4b.yaml\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"data_path\": \"data/conll2003\", \"data_count\": 14041, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"D096\", \"log_path\": \"checkpoints/qwen3-4b-conll2003-lora/trainer_log.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-lora\", \"lora_config\": {\"trainable_params\": \"66M / 4.09B (1.62%)\", \"target_modules\": \"q_proj, k_proj, v_proj, o_proj, gate_proj, up_proj, down_proj\", \"epochs\": 5, \"batch_size\": 16, \"total_steps\": 4390, \"enable_thinking\": false}}, \"conclusion\": \"success\", \"notes\": \"Training stopped at step 3920/4390 (89.3%, epoch 4.46/5). No error log or tmux session found. checkpoint-3800 is valid (adapter_model.safetensors 264MB, eval_loss=0.023). Proceeding with checkpoint-3800 for merge+inference.\", \"metrics\": {\"final_loss\": 0.0086, \"total_steps_completed\": 3920, \"total_steps_target\": 4390, \"epochs_completed\": 4.46, \"epochs_target\": 5, \"best_checkpoint\": \"checkpoint-3800\", \"note\": \"Training stopped at 89.3% completion (no error log found). Using checkpoint-3800 (loss ~0.01) for merge.\"}}, \"exp_freeform_seed789_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:02:03.813Z\", \"updated_at\": \"2026-05-15T19:06:44.537Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python run_freeform_inference.py --seed 789 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed789\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"218882\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_seed789_v2.log\", \"submitted_at\": \"2026-05-15T19:02:03.527Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"hypothesis\": \"Multi-seed free-form ablation (seed=789): third seed for 3-seed mean±σ statistical significance. Verify RE LP flip and NER gap stability.\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 789, \"wall_clock_seconds\": 274.9, \"gpu_hours\": 0.08}, \"reproduce\": {\"finished_at\": \"2026-05-15T19:06:37.887Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T19:06:38.388Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T19:06:53.109123+00:00\"}]}}, \"exp_qwen3_4b_scierc_finetune\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:58:58.948Z\", \"updated_at\": \"2026-05-15T19:03:05.505Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli train train_config_scierc_4b.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"218258\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune.log\", \"submitted_at\": \"2026-05-15T19:00:10.234Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 175.3, \"gpu_hours\": 0.05}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:03:05.505Z\"}, \"exp_lp_t07_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:34:12.094Z\", \"updated_at\": \"2026-05-15T16:30:35.531Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 8 --temperature 0.7 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_lp_t07_scierc\\\"\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-8B (LoRA fine-tuned on SciERC, ft_002_v2 merged)\", \"seed\": 42, \"gpu\": \"cuda:1\", \"hyperparams\": {\"n_samples\": 8, \"temperature\": 0.7, \"max_tokens\": 1024}}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T16:28:29.563Z\"}, \"exp_lp_scierc_t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:34:06.918Z\", \"updated_at\": \"2026-05-15T16:03:13.881Z\", \"hypothesis\": \"LP T=0.7 推理：验证低温下 LP score compression 是否依然存在，强化 \\\"LP compression is model/task intrinsic\\\" claim。对比 T=1.0 的 LP range 分布。\", \"spec\": {\"command\": \"python run_sc_ie.py --dataset scierc --subtask ner --model qwen --n_samples 8 --temperature 0.7 --use_logprob --output_dir /root/autodl-tmp/struct_self_consist_ie/output/exp_lp_scierc_t07\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"196993\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_lp_scierc_t07/\", \"submitted_at\": \"2026-05-15T15:35:31.692Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"SciERC\", \"data_count\": 500, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_lp_scierc_t07/report.json\", \"wall_clock_seconds\": 1206.2, \"gpu_hours\": 0.34}, \"conclusion\": \"success\", \"metrics\": {\"ner_greedy_f1\": 0.662, \"ner_oracle_f1\": 0.764, \"ner_headroom_pp\": 10.2, \"ner_rho_sj_full\": 0.365, \"ner_rho_sj_cond\": 0.363, \"ner_rho_fk_full\": 0.289, \"ner_rho_fk_cond\": 0.255, \"lp_rho_full\": 0.249, \"lp_rho_cond\": 0.185, \"ner_rho_advantage\": 0.076, \"zero_f1_pct\": 11, \"full_n\": 529, \"cond_n\": 477, \"verdict\": \"success_supports_LP_compression_claim\"}, \"completed_at\": \"2026-05-15T15:55:37.889Z\"}, \"exp_re_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:40:40.607Z\", \"updated_at\": \"2026-05-15T15:55:41.890Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_re_scierc_seed456\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"199161\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed456/\", \"submitted_at\": \"2026-05-15T15:40:59.585Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"SciERC\", \"data_count\": 500, \"model_name\": \"Qwen3-8B (SciERC merged)\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed456/report.json\", \"wall_clock_seconds\": 882.3, \"gpu_hours\": 0.25}, \"hypothesis\": \"SciERC RE 多种子验证 (seed456): 解决 R4-W1/R7-C1 single-seed RE 弱点。与 seed42 (exp_012_rerun_1024) 对齐，joint subtask N=8 T=1.0。目标: 3-seed RE selection F1 mean±σ。\", \"conclusion\": \"negative\", \"metrics\": {\"ner_greedy_f1\": 0.664, \"ner_oracle_f1\": 0.775, \"ner_headroom_pp\": 11.1, \"ner_rho_sj_cond\": 0.283, \"ner_rho_fk_cond\": 0.145, \"re_greedy_f1\": 0.417, \"re_oracle_f1\": 0.581, \"re_headroom_pp\": 16.3, \"re_rho_sj_cond\": 0.315, \"re_rho_fk_cond\": 0.123, \"re_zero_f1_pct\": 45.3, \"verdict\": \"FAIL_re_rho_sj_below_040\"}, \"completed_at\": \"2026-05-15T15:55:41.890Z\"}, \"exp_re_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:40:38.271Z\", \"updated_at\": \"2026-05-15T15:55:40.000Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_re_scierc_seed123\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"199021\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed123/\", \"submitted_at\": \"2026-05-15T15:40:58.073Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"SciERC\", \"data_count\": 500, \"model_name\": \"Qwen3-8B (SciERC merged)\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed123/report.json\", \"wall_clock_seconds\": 881.9, \"gpu_hours\": 0.24}, \"hypothesis\": \"SciERC RE 多种子验证 (seed123): 解决 R4-W1/R7-C1 single-seed RE 弱点。与 seed42 (exp_012_rerun_1024) 对齐，joint subtask N=8 T=1.0。目标: 3-seed RE selection F1 mean±σ。\", \"conclusion\": \"negative\", \"metrics\": {\"ner_greedy_f1\": 0.663, \"ner_oracle_f1\": 0.786, \"ner_headroom_pp\": 12.3, \"ner_rho_sj_cond\": 0.404, \"ner_rho_fk_cond\": 0.182, \"re_greedy_f1\": 0.42, \"re_oracle_f1\": 0.593, \"re_headroom_pp\": 17.3, \"re_rho_sj_cond\": 0.277, \"re_rho_fk_cond\": 0.063, \"re_zero_f1_pct\": 43.6, \"verdict\": \"FAIL_re_rho_sj_below_040\"}, \"completed_at\": \"2026-05-15T15:55:40.000Z\"}, \"exp_017_llama_conll_n8_t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:29:34.595Z\", \"updated_at\": \"2026-05-15T15:46:22.722Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.7 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n8_t07\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"195927\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_017_llama_conll_n8_t07.log\", \"submitted_at\": \"2026-05-15T15:31:17.989Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 881.3, \"gpu_hours\": 0.24}, \"hypothesis\": \"LLaMA CoNLL N=8 T=0.7 防御性实验：填补\\\"LLaMA 仅在 SciERC 上测过\\\"的弱点，验证 cross-model consistency（vs Qwen CoNLL）。T=0.7 低温下 confidence signals 的 correlation-selection gap 是否依然存在。\", \"parent\": \"exp_017_llama_conll\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-15T15:31:15.772Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.7 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n8_t07\\\"\", \"finished_at\": \"2026-05-15T15:40:02.605Z\", \"training_hours\": 0.15}, \"pid\": \"195927\", \"log_path\": \"/root/runs/struct_self_consist_ie/exp_017_llama_conll_n8_t07.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:40:08.277684+00:00\"}]}, \"metrics\": {\"n_valid\": 2756, \"greedy_f1\": 0.9242, \"oracle_f1\": 0.9391, \"lp_range_median\": 1.1e-05, \"lp_tied_fraction_005\": 0.9579, \"signals\": {\"SJ\": {\"rho\": 0.3934, \"auroc\": 0.6506}, \"FK\": {\"rho\": 0.3879, \"auroc\": 0.6488}, \"VC\": {\"rho\": 0.375, \"auroc\": 0.6551}, \"EM\": {\"rho\": 0.3888, \"auroc\": 0.6494}, \"LP\": {\"rho\": 0.2951, \"auroc\": 0.7509}}, \"selection_f1\": {\"SJ\": 0.9247, \"FK\": 0.9254, \"VC\": 0.9264, \"EM\": 0.9255, \"LP\": 0.9248}}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (inference-only)\", \"completed_at\": \"2026-05-15T15:45:59.311Z\"}, \"exp008_re_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:50.987Z\", \"updated_at\": \"2026-05-15T12:41:39.774Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp008_re_n16 && CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp008_re_n16 --collect_logprobs 2>&1 | tee output/exp008_re_n16/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:2\"], \"pid\": \"53600\", \"log_path\": \"~/runs/struct_self_consist_ie/exp008_re_n16.log\", \"submitted_at\": \"2026-05-14T12:15:14.917Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_008_re_n16_v2 (full 551-instance run on autodl-5090)\", \"wall_clock_seconds\": 87984.9, \"gpu_hours\": 24.44}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T12:41:39.774Z\"}, \"exp001_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:48.078Z\", \"updated_at\": \"2026-05-15T12:41:32.192Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp001_n16_seed456 && CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --output_dir output/exp001_n16_seed456 --collect_logprobs 2>&1 | tee output/exp001_n16_seed456/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:1\"], \"pid\": \"50302\", \"log_path\": \"~/runs/struct_self_consist_ie/exp001_seed456.log\", \"submitted_at\": \"2026-05-14T12:12:41.206Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed456_v2_ner (NER-only on autodl-5090)\", \"wall_clock_seconds\": 88131.0, \"gpu_hours\": 24.48}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:32.192Z\"}, \"exp001_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:45.739Z\", \"updated_at\": \"2026-05-15T12:41:31.168Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp001_n16_seed123 && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --output_dir output/exp001_n16_seed123 --collect_logprobs 2>&1 | tee output/exp001_n16_seed123/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"48530\", \"log_path\": \"~/runs/struct_self_consist_ie/exp001_seed123.log\", \"submitted_at\": \"2026-05-14T12:09:45.674Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed123_v2 (NER-only, 551 instances on autodl-5090)\", \"wall_clock_seconds\": 88305.5, \"gpu_hours\": 24.53}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:31.168Z\"}, \"exp_001_n16_seed456_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:44:31.348Z\", \"updated_at\": \"2026-05-15T12:41:30.065Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --num_test 9999 --output_dir output/exp001_n16_seed456/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:1\"], \"pid\": \"62170\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_n16_seed456_full.log\", \"submitted_at\": \"2026-05-14T12:44:31.087Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed456_v2_ner (NER-only on autodl-5090)\", \"wall_clock_seconds\": 86219.0, \"gpu_hours\": 23.95}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:30.065Z\"}, \"exp_001_n16_seed123_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:43:47.915Z\", \"updated_at\": \"2026-05-15T12:41:29.068Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --num_test 9999 --output_dir output/exp001_n16_seed123_full/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"61812\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_n16_seed123_full.log\", \"submitted_at\": \"2026-05-14T12:44:06.059Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed123_v2 (NER-only on autodl-5090)\", \"wall_clock_seconds\": 86243.0, \"gpu_hours\": 23.96}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:29.068Z\"}, \"exp_007_ner_llama\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:21.510Z\", \"updated_at\": \"2026-05-15T12:41:27.410Z\", \"spec\": {\"description\": \"Fine-tune LLaMA-3.1-8B on SciERC + NER pilot (N=8, T=0.7). Model-agnostic validation.\", \"hypothesis\": \"SJ advantage is model-agnostic, not Qwen3-specific\", \"plan_id\": \"exp-007\", \"claim\": 1, \"model_name\": \"llama-3.1-8b-instruct (new fine-tune)\", \"dataset\": \"SciERC\", \"priority\": \"P0\", \"failure_reason\": \"Superseded by exp_007_ner_multi_model + exp_007_llama_inference (completed on autodl-5090)\"}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_007_llama_inference (DONE)\", \"notes\": \"Completed as exp_007_llama_n16 on autodl-5090. Registry status corrected.\", \"completed_at\": \"2026-05-15T12:41:27.410Z\"}, \"exp_002_merge_conll2003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:25:56.211Z\", \"updated_at\": \"2026-05-15T12:41:26.419Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli export export_config_conll2003.yaml > /tmp/merge_conll2003.log 2>&1 && echo 'MERGE_DONE' >> /tmp/merge_conll2003.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"57524\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_merge_conll2003.log\", \"submitted_at\": \"2026-05-14T12:25:56.139Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_002_ner_conll2003 (completed on autodl-5090)\", \"wall_clock_seconds\": 87330.3, \"gpu_hours\": 24.26}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_002_ner_conll2003 (DONE)\", \"notes\": \"Completed as exp_002_conll_n16 on autodl-5090. Registry status corrected.\", \"completed_at\": \"2026-05-15T12:41:26.419Z\"}, \"exp_019_supervised_verifier\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:08:54.395Z\", \"updated_at\": \"2026-05-15T12:40:53.995Z\", \"spec\": {\"hypothesis\": \"Supervised verifier (DeBERTa-v3-large) can close the correlation-selection gap, proving the gap is closable with supervision\", \"plan_id\": \"exp-019\", \"model_name\": \"microsoft/deberta-v3-large\", \"data_path\": \"output/exp_012_rerun_1024/samples.jsonl\", \"data_count\": 551, \"seed\": 42}, \"conclusion\": \"killed\", \"notes\": \"Cancelled by Director: DDL risk too high (3-4 days for implementation+training+eval+paper), scope creep for analytical paper, free-form ablation already provides sufficient mechanistic evidence\", \"completed_at\": \"2026-05-15T12:40:53.995Z\"}, \"exp_018_llama_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:15.150Z\", \"updated_at\": \"2026-05-15T06:22:40.868Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: LLaMA SciERC N=8 seed=456, max_tokens=1024. Fresh inference (D066 decision: replace exp_007 re-analysis with independent replication).\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed456_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T06:08:05.756Z\", \"notes\": \"SUPERSEDED by exp_018_llama_scierc_seed456_r1024 (D066). Original data was re-analysis of exp_007_llama_seed456, not independent inference. Fresh rerun with explicit max_tokens=1024 now canonical.\"}, \"exp_002_conll_n16_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:57.682Z\", \"updated_at\": \"2026-05-15T01:20:53.108Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen CoNLL N=16.\", \"parent\": \"exp_002_conll_n16\", \"model_name\": \"qwen3-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_002_conll_n16_r1024\", \"data_path\": \"data/conll2003\", \"data_count\": 3453}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:53.108Z\"}, \"exp_007_llama_n16_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:59.685Z\", \"updated_at\": \"2026-05-15T01:20:52.194Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA SciERC N=16.\", \"parent\": \"exp_007_llama_n16\", \"model_name\": \"llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_007_llama_n16_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:52.194Z\"}, \"exp_001_seed123_v2_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:54.442Z\", \"updated_at\": \"2026-05-15T01:20:49.812Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed123.\", \"parent\": \"exp_001_seed123_v2\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 123, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed123_v2_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 529}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:49.812Z\"}, \"exp_001_seed456_v2_ner_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:55.975Z\", \"updated_at\": \"2026-05-15T01:20:48.914Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed456.\", \"parent\": \"exp_001_seed456_v2_ner\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 456, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed456_v2_ner_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:48.914Z\"}, \"exp_001_seed42_v2_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:52.571Z\", \"updated_at\": \"2026-05-14T22:28:53.686Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed42.\", \"parent\": \"exp_001_seed42_v2\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed42_v2_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"metrics\": {\"greedy_f1\": 0.6647, \"oracle_f1\": 0.8106, \"softjaccard_rho_full\": 0.3928, \"fleiss_rho_full\": 0.2489, \"logprob_rho_full\": 0.2136, \"softjaccard_rho_cond\": 0.3455, \"fleiss_rho_cond\": 0.163, \"logprob_rho_cond\": 0.1624, \"verdict\": \"MARGINAL\"}, \"checkpoint_path\": \"output/exp_001_seed42_v2_r1024\", \"log_path\": \"output/exp_001_seed42_v2_r1024/run.log\", \"completed_at\": \"2026-05-14T22:27:43.836Z\"}, \"exp_017_llama_conll_n16_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:23:21.987Z\", \"updated_at\": \"2026-05-14T20:24:45.875Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=456: structural>surface ranking preserved across seeds, complementing Qwen SciERC 3-seed protocol\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --num_test 9999 --output_dir output/exp_017_llama_conll_n16_s456\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"llama3.1-8b-conll2003-merged\", \"seed\": 456}, \"metrics\": {\"greedy_f1\": 0.9243, \"oracle_f1\": 0.9488, \"oracle_headroom\": 0.0245, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4552, \"SJ_AUROC\": 0.7288, \"SJ_ECE\": 0.1134, \"FK_rho\": 0.4478, \"FK_AUROC\": 0.7248, \"FK_ECE\": 0.109, \"logprob_rho\": 0.3078, \"logprob_AUROC\": 0.7612, \"logprob_ECE\": 0.1289, \"EM_rho\": 0.452, \"EM_AUROC\": 0.7275, \"EM_ECE\": 0.1082, \"voting_conf_rho\": 0.4571, \"voting_conf_AUROC\": 0.7348, \"voting_conf_ECE\": 0.0863}, \"conditional\": {\"SJ_rho\": 0.4505, \"SJ_AUROC\": 0.7449, \"SJ_ECE\": 0.0826, \"FK_rho\": 0.4422, \"FK_AUROC\": 0.7401, \"FK_ECE\": 0.0835, \"logprob_rho\": 0.3242, \"logprob_AUROC\": 0.8067, \"logprob_ECE\": 0.0921, \"EM_rho\": 0.451, \"EM_AUROC\": 0.745, \"EM_ECE\": 0.0756, \"voting_conf_rho\": 0.3962, \"voting_conf_AUROC\": 0.7202, \"voting_conf_ECE\": 0.0746}, \"best_of_n\": {\"greedy\": 0.9243, \"random_avg\": 0.9215, \"sj_best\": 0.9243, \"logprob_best\": 0.9243, \"voting_conf_best\": 0.9243, \"oracle\": 0.9488}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0238, \"full_FK_rho_delta\": 0.0201, \"full_logprob_rho_delta\": 0.0006, \"full_EM_rho_delta\": 0.0214, \"full_voting_conf_rho_delta\": 0.0315, \"cond_SJ_rho_delta\": 0.0149, \"cond_FK_rho_delta\": 0.0112, \"cond_logprob_rho_delta\": -0.004, \"cond_EM_rho_delta\": 0.0107, \"cond_voting_conf_rho_delta\": 0.0219}}, \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s456/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16_s456/all_signals_report.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T20:24:45.875Z\"}, \"exp_017_llama_conll_n16_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:23:21.084Z\", \"updated_at\": \"2026-05-14T19:43:06.607Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=123: structural>surface ranking preserved across seeds, complementing Qwen SciERC 3-seed protocol\", \"spec\": {\"hypothesis\": \"LLaMA CoNLL-2003 NER N=16 seed=123: cross-seed robustness check against N=8 seed=42 baseline (exp_017_llama_conll_infer)\", \"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --num_test 9999 --output_dir output/exp_017_llama_conll_n16_s123\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 3453, \"model_name\": \"llama3.1-8b-conll2003-merged\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/llama3.1-8b-conll2003-merged\", \"eval_data\": \"data/conll2003\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s123/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16_s123.log\"}, \"metrics\": {\"greedy_f1\": 0.9266, \"oracle_f1\": 0.9497, \"oracle_headroom\": 0.0231, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4698, \"SJ_AUROC\": 0.7402, \"SJ_ECE\": 0.1135, \"FK_rho\": 0.4594, \"FK_AUROC\": 0.7351, \"FK_ECE\": 0.1114, \"logprob_rho\": 0.3161, \"logprob_AUROC\": 0.768, \"logprob_ECE\": 0.129, \"EM_rho\": 0.4676, \"EM_AUROC\": 0.7399, \"EM_ECE\": 0.1082, \"voting_conf_rho\": 0.4612, \"voting_conf_AUROC\": 0.7429, \"voting_conf_ECE\": 0.0832}, \"conditional\": {\"SJ_rho\": 0.4712, \"SJ_AUROC\": 0.7609, \"SJ_ECE\": 0.0828, \"FK_rho\": 0.4595, \"FK_AUROC\": 0.7547, \"FK_ECE\": 0.0858, \"logprob_rho\": 0.3314, \"logprob_AUROC\": 0.8134, \"logprob_ECE\": 0.0922, \"EM_rho\": 0.4732, \"EM_AUROC\": 0.7626, \"EM_ECE\": 0.075, \"voting_conf_rho\": 0.4086, \"voting_conf_AUROC\": 0.7338, \"voting_conf_ECE\": 0.0706}, \"best_of_n\": {\"greedy\": 0.9242, \"random_avg\": 0.9216, \"sj_best\": 0.9247, \"logprob_best\": 0.9253, \"voting_conf_best\": 0.9255, \"oracle\": 0.9486}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0384, \"full_FK_rho_delta\": 0.0317, \"full_logprob_rho_delta\": 0.0089, \"full_SJ_AUROC_delta\": 0.0363, \"full_FK_AUROC_delta\": 0.0325, \"full_logprob_AUROC_delta\": 0.007, \"cond_SJ_rho_delta\": 0.0356, \"cond_FK_rho_delta\": 0.0285, \"cond_logprob_rho_delta\": 0.0032}}, \"log_path\": \"output/exp_017_llama_conll_n16_s123.log\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s123/samples.jsonl\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T19:43:06.607Z\"}, \"exp_008_re_n16_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:45:10.852Z\", \"updated_at\": \"2026-05-14T17:51:43.957Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs --num_test 9999 --output_dir output/exp008_re_n16/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:2\"], \"pid\": \"62585\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_008_re_n16_full.log\", \"submitted_at\": \"2026-05-14T12:45:10.764Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 18393.2, \"gpu_hours\": 5.11}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_008_re_n16_t10_full (full 551-instance RE-only run on autodl-5090)\", \"completed_at\": \"2026-05-14T17:51:43.957Z\"}, \"exp_001_n16_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:10:29.393Z\", \"updated_at\": \"2026-05-14T12:42:58.393Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs\", \"server\": \"gpu-5090-4x-2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"num_instances\": 200, \"partial\": true, \"note\": \"Only 200/551 instances due to --num_test default bug. Needs full rerun.\"}, \"metrics\": {\"ner\": {\"greedy_f1\": 0.655, \"oracle_f1\": 0.8028, \"headroom\": 0.1478, \"rho_sj_full\": 0.4076, \"rho_fk_full\": 0.2799, \"rho_logprob_full\": 0.3189, \"rho_sj_cond\": 0.4271, \"rho_fk_cond\": 0.2743, \"rho_logprob_cond\": 0.2835, \"sj_beats_fk\": true, \"rho_advantage\": 0.1277}, \"re\": {\"greedy_f1\": 0.4243, \"oracle_f1\": 0.6771, \"headroom\": 0.2528, \"rho_sj_full\": 0.2943, \"rho_fk_full\": 0.2657, \"rho_logprob_full\": 0.3005, \"rho_sj_cond\": 0.4003, \"rho_fk_cond\": 0.313, \"rho_logprob_cond\": 0.2317, \"sj_beats_fk\": true, \"rho_advantage\": 0.0286}, \"verdict\": \"FAIL\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp001_n16_seed123/\", \"completed_at\": \"2026-05-14T12:28:38.104Z\"}, \"exp_016_signal_ensemble\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:15:23.771Z\", \"updated_at\": \"2026-05-14T12:42:55.931Z\", \"spec\": {\"command\": \"python code/analyze_exp016_ensemble.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"model_name\": \"N/A (CPU-only analysis)\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"eval_data\": \"pilot_004\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp016_signal_ensemble/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:15:53.341Z\", \"metrics\": {\"sj_logprob_pearson_ner\": 0.57, \"sj_logprob_pearson_re\": 0.42, \"best_linear_ner\": {\"combo\": \"SJ+voting_conf\", \"alpha\": 0.3, \"rho\": 0.489}, \"best_linear_re\": {\"combo\": \"voting_conf+logprob\", \"alpha\": 0.6, \"rho\": 0.429}, \"ensemble_ner_auroc\": 0.735, \"ensemble_re_auroc\": 0.719, \"best_single_ner_auroc\": 0.7, \"best_single_re_auroc\": 0.721, \"ensemble_ner_delta\": 0.035, \"selection_f1_ner\": {\"greedy\": 0.609, \"logprob\": 0.609, \"sj\": 0.604, \"ensemble\": 0.604, \"voting\": 0.596, \"random\": 0.58, \"oracle\": 0.769}, \"selection_f1_re\": {\"logprob\": 0.397, \"greedy\": 0.374, \"sj\": 0.368, \"ensemble\": 0.367, \"voting\": 0.338, \"random\": 0.338, \"oracle\": 0.561}, \"diagnosis\": \"SJ+voting_conf linear combo boosts NER ρ to 0.489 (+23%). RE: logprob-best is ONLY method beating greedy (0.397 vs 0.374). Ensemble AUROC +0.035 on NER. Oracle gap still huge.\"}}, \"exp_001_ner_n16_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:10.898Z\", \"updated_at\": \"2026-05-14T12:42:49.592Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp001_n16_seed42 --num_test 9999 --collect_logprobs 2>&1 | tee output/exp001_n16_seed42_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"54357\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_ner_n16_scierc.log\", \"submitted_at\": \"2026-05-14T12:15:46.646Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T11:43:48.643Z\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:55:45.664Z\", \"metrics\": {\"n_instances\": 551, \"ner_n\": 529, \"re_n\": 397, \"N\": 16, \"T\": 1, \"seed\": 42, \"full_test_set\": true, \"ner_voting_conf_rho\": 0.399, \"ner_sj_rho\": 0.398, \"ner_em_rho\": 0.339, \"ner_fk_rho\": 0.288, \"ner_logprob_rho\": 0.237, \"ner_voting_conf_auroc\": 0.704, \"ner_sj_auroc\": 0.697, \"ner_cond_em_rho\": 0.414, \"ner_cond_sj_rho\": 0.349, \"ner_cond_vc_rho\": 0.34, \"re_voting_conf_rho\": 0.38, \"re_logprob_rho\": 0.293, \"re_fk_rho\": 0.281, \"re_sj_rho\": 0.277, \"re_em_rho\": 0.148, \"re_voting_conf_auroc\": 0.699, \"re_cond_em_rho\": 0.475, \"re_cond_sj_rho\": 0.318, \"re_cond_vc_rho\": 0.35, \"re_cond_em_auroc\": 0.742, \"diagnosis\": \"551 instances T=1.0: voting_conf best on full set (NER 0.399, RE 0.380). EM SURPRISE best on conditional set (NER cond 0.414, RE cond 0.475). RE full FAIL (SJ 0.277 < 0.40). Previous N-scaling 'breakthrough' was artifact of 200 instances + T=0.7.\"}}, \"exp_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:39:53.226Z\", \"updated_at\": \"2026-05-14T12:40:17.202Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --collect_logprobs --num_test 99999\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-lora-merged\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll2003-merged\", \"log_path\": \"/tmp/pilot_conll2003.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:40:08.402Z\", \"metrics\": {\"sj_rho_full\": 0.4357, \"sj_tau_full\": 0.3851, \"sj_auroc_full\": 0.8008, \"sj_rho_cond\": 0.4511, \"fk_rho_full\": 0.3998, \"fk_tau_full\": 0.3568, \"fk_auroc_full\": 0.7741, \"fk_rho_cond\": 0.4064, \"logprob_rho_full\": 0.3157, \"logprob_tau_full\": 0.2469, \"logprob_auroc_full\": 0.7532, \"logprob_rho_cond\": 0.3562, \"em_rho_full\": 0.4507, \"em_tau_full\": 0.4002, \"em_auroc_full\": 0.8156, \"em_rho_cond\": 0.4799, \"ev_rho_full\": 0.4237, \"ev_tau_full\": 0.3777, \"ev_auroc_full\": 0.7889, \"ev_rho_cond\": 0.4127, \"greedy_f1\": 0.9123, \"oracle_f1\": 0.9543, \"voting_f1\": 0.9141, \"oracle_headroom\": 0.042, \"sj_vs_logprob_delta_rho\": 0.12, \"sj_vs_logprob_ci_low\": 0.0881, \"sj_vs_logprob_ci_high\": 0.154, \"sj_vs_logprob_significant\": true, \"n_instances\": 3453, \"n_valid\": 2756, \"n_samples\": 8, \"temperature\": 1}}, \"exp_002_ner_conll2003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:15.223Z\", \"updated_at\": \"2026-05-14T12:27:35.413Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp002_conll2003 --num_test 99999 --seed 42 --collect_logprobs 2>&1 | tee /tmp/pilot_conll2003.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"58208\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_ner_conll2003.log\", \"submitted_at\": \"2026-05-14T12:27:35.337Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-14T11:43:49.959Z\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll2003-lora\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_ner_conll2003.log\", \"completed_at\": \"2026-05-14T12:18:04.097Z\"}, \"exp_004_re_diagnostic\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:49:44.497Z\", \"updated_at\": \"2026-05-14T11:50:24.620Z\", \"spec\": {\"hypothesis\": \"RE diagnostic: per-relation-type breakdown reveals which types drive low RE rho; error propagation and threshold sensitivity clarify the gap between NER and RE consistency signals\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Per-relation-type SJ/FK/voting rho, error propagation classification, threshold sensitivity, bootstrap CI, Fisher z-test NER vs RE\", \"command\": \"python3 code/analyze_exp004_re_diagnostic.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004_re_diagnostic\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004_re_diagnostic/\", \"checkpoint_source\": \"mvp_pilot_004\", \"eval_data\": \"scierc_test_551\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:50:04.662Z\", \"metrics\": {\"per_relation_type\": {\"HYPONYM-OF\": {\"n\": 36, \"rho_sj\": 0.545, \"rho_fk\": 0.646, \"rho_vc\": 0.628, \"mean_f1\": 0.513}, \"CONJUNCTION\": {\"n\": 86, \"rho_sj\": 0.383, \"rho_fk\": 0.35, \"rho_vc\": 0.484, \"mean_f1\": 0.48}, \"USED-FOR\": {\"n\": 299, \"rho_sj\": 0.236, \"rho_fk\": 0.255, \"rho_vc\": 0.286, \"mean_f1\": 0.422}, \"PART-OF\": {\"n\": 44, \"rho_sj\": 0.239, \"rho_fk\": 0.348, \"rho_vc\": 0.283, \"mean_f1\": 0.297}, \"EVALUATE-FOR\": {\"n\": 62, \"rho_sj\": 0.172, \"rho_fk\": 0.255, \"rho_vc\": 0.226, \"mean_f1\": 0.365}, \"COMPARE\": {\"n\": 35, \"rho_sj\": 0.168, \"rho_fk\": 0.184, \"rho_vc\": 0.18, \"mean_f1\": 0.453}, \"FEATURE-OF\": {\"n\": 50, \"rho_sj\": 0.004, \"rho_fk\": 0.052, \"rho_vc\": 0.014, \"mean_f1\": 0.254}}, \"error_propagation\": {\"total_fn\": 553, \"tail_error_pct\": 21.9, \"full_error_pct\": 21.7, \"head_error_pct\": 17.7, \"head_tail_error_pct\": 15.9, \"type_error_pct\": 8.3, \"worst_consistency\": \"head_type_error (sj=0.411)\", \"best_consistency\": \"head_error (sj=0.613)\"}, \"threshold_sensitivity\": {\"thr_0.00_rho_sj\": 0.3161, \"thr_0.00_rho_vc\": 0.3841, \"thr_0.00_n\": 313, \"thr_0.05_rho_sj\": 0.2682, \"thr_0.05_rho_vc\": 0.2364, \"thr_0.05_n\": 239}, \"bootstrap_ci_95\": {\"ner_sj\": [0.2946, 0.4586], \"ner_voting_conf\": [0.3048, 0.4656], \"re_sj\": [0.1422, 0.3391], \"re_voting_conf\": [0.1818, 0.3721], \"re_cond_sj\": [0.2161, 0.4102], \"re_cond_voting_conf\": [0.2825, 0.474]}, \"fisher_z_ner_vs_re\": {\"sj_z\": 2.31, \"sj_p\": 0.0209, \"sj_significant\": true, \"fk_z\": -0.31, \"fk_p\": 0.756, \"fk_significant\": false, \"voting_z\": 1.914, \"voting_p\": 0.0556, \"voting_significant\": false}, \"diagnosis\": \"FEATURE-OF is near-zero rho across all signals (n=50, F1=0.254). HYPONYM-OF strongest (rho_fk=0.646). Entity span errors (head+tail) account for 55.5% of RE FN. NER rho_sj significantly > RE rho_sj (p=0.021). Voting_conf is best RE signal in conditional set (rho=0.384).\"}}, \"exp_005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:45:16.360Z\", \"updated_at\": \"2026-05-14T11:45:38.570Z\", \"spec\": {\"hypothesis\": \"Temperature sensitivity: systematic comparison of T=0.7 vs T=1.0 on all 5 confidence signals\", \"method\": \"CPU-only analysis from checkpoint metrics (pilot_004 T=1.0, pilot_005 T=0.7, exp_012/013/014)\", \"data_count\": 551, \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2\", \"data_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/exp005_temperature/\", \"server\": \"local\", \"seed\": 42, \"parent\": \"mvp_pilot_004,mvp_pilot_005\", \"command\": \"python3 analyze_exp005_temperature.py\", \"checkpoint_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/exp005_temperature/\", \"log_path\": \"N/A\", \"checkpoint_source\": \"pilot_004+pilot_005 checkpoint metrics\", \"eval_data\": \"SciERC test set (n=551)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:45:38.570Z\"}, \"exp_014_entity_majority_voting\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:21.203Z\", \"updated_at\": \"2026-05-14T11:33:30.085Z\", \"spec\": {\"hypothesis\": \"Entity-level majority voting confidence beats SJ as correlation signal\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Per-entity voting across N=8 samples, consensus construction, confidence = mean voting rate\", \"command\": \"python code/analyze_entity_voting.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp014_entity_voting_report.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:18:09.468Z\", \"metrics\": {\"ner_full_rho\": 0.3915, \"ner_full_p\": 8.1e-21, \"ner_full_tau\": 0.2906, \"ner_full_auroc\": 0.7039, \"re_full_rho\": 0.3403, \"re_full_p\": 3.21e-12, \"re_full_tau\": 0.256, \"re_full_auroc\": 0.6668, \"ner_voting_f1\": 0.6246, \"ner_greedy_f1\": 0.6483, \"ner_oracle_f1\": 0.7793, \"re_voting_f1\": 0.3577, \"re_greedy_f1\": 0.4022, \"re_oracle_f1\": 0.5886, \"diagnosis\": \"Voting confidence BEATS SJ on both NER (rho 0.392 vs 0.383) and RE (0.340 vs 0.244). But voting as selection strategy LOSES to greedy.\"}}, \"exp_013_exact_match_voting\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:18.753Z\", \"updated_at\": \"2026-05-14T11:33:22.644Z\", \"spec\": {\"hypothesis\": \"Exact-match voting rate correlates with F1\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Count exact-match duplicates across N=8 samples\", \"command\": \"python code/analyze_exact_match_voting.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp013_exact_match_report.json\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T11:18:09.026Z\", \"metrics\": {\"ner_full_rho\": 0.2941, \"ner_full_p\": 5.12e-12, \"ner_full_tau\": 0.2181, \"ner_full_auroc\": 0.6398, \"re_full_rho\": 0.1562, \"re_full_p\": 0.0018, \"re_full_tau\": 0.1185, \"re_full_auroc\": 0.5863, \"diagnosis\": \"EM between SJ and FK on NER, weakest on RE. Too coarse-grained.\"}}, \"exp_012_logprob_baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:16.166Z\", \"updated_at\": \"2026-05-14T11:13:30.240Z\", \"spec\": {\"hypothesis\": \"Log-probability baseline: mean sequence log-prob correlates with F1 as well as or better than SJ\", \"model_name\": \"ft_002_v2 (qwen3-8b-scierc-merged-v2)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"vLLM forward pass for log-probs + Spearman rho + AUROC + Kendall tau\", \"command\": \"python3 code/extract_logprobs.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/logprob_analysis.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:06:42.542Z\", \"metrics\": {\"ner_full_rho_sj\": 0.3565, \"ner_full_rho_fk\": 0.2651, \"ner_full_rho_logprob\": 0.1396, \"ner_full_rho_greedy_logprob\": 0.1615, \"ner_full_tau_sj\": 0.2658, \"ner_full_tau_logprob\": 0.1006, \"ner_full_auroc_sj\": 0.6892, \"ner_full_auroc_fk\": 0.6292, \"ner_full_auroc_logprob\": 0.5907, \"ner_full_n\": 529, \"ner_sj_vs_logprob_delta\": 0.2169, \"re_full_rho_sj\": 0.2112, \"re_full_rho_fk\": 0.2528, \"re_full_rho_logprob\": 0.2467, \"re_full_auroc_sj\": 0.5916, \"re_full_auroc_fk\": 0.6262, \"re_full_auroc_logprob\": 0.6186, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3683, \"re_cond_rho_fk\": 0.3168, \"re_cond_rho_logprob\": 0.1457, \"re_cond_auroc_sj\": 0.6839, \"re_cond_auroc_logprob\": 0.5487, \"re_cond_n\": 296, \"diagnosis\": \"NER: SJ crushes logprob (rho +0.217). RE full: logprob slightly ahead. RE cond: SJ crushes logprob (rho +0.223). SJ unique value CONFIRMED.\"}}, \"mvp_pilot_005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:14:09.456Z\", \"updated_at\": \"2026-05-14T09:47:06.597Z\", \"spec\": {\"hypothesis\": \"T=0.7 降低 RE zero rate，恢复 SJ>FK，rho_sj 可能 ≥ 0.30 (MARGINAL threshold)\", \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2 (ft_002_v2 final)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_002_v2\", \"method\": \"N=8 sampling T=0.7 + XGrammar + span realignment + max_tokens=1024 + gold-empty filter + conditional rho\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.7 --max_tokens 1024 --output_dir output/mvp_pilot_005 --num_test 551 --seed 42 --tensor_parallel 1\", \"gpu\": \"cuda:0\", \"pid\": 32456, \"tmux_session\": \"mvp_pilot_005\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_005/train.log\"}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_005\", \"metrics\": {\"ner_greedy_f1\": 0.6619, \"ner_oracle_f1\": 0.7585, \"ner_headroom\": 0.0966, \"ner_fleiss_kappa_mean\": 0.4722, \"ner_soft_jaccard_mean\": 0.7757, \"ner_full_rho_sj\": 0.3875, \"ner_full_rho_fk\": 0.3211, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3868, \"ner_cond_rho_fk\": 0.305, \"ner_cond_n\": 504, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_rho_advantage\": 0.0664, \"ner_sample_f1_mean\": 0.6243, \"ner_sample_f1_std\": 0.3131, \"ner_sample_f1_pct_zero\": 11.2, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 25, \"re_greedy_f1\": 0.4219, \"re_oracle_f1\": 0.5532, \"re_headroom\": 0.1313, \"re_fleiss_kappa_mean\": 0.3829, \"re_soft_jaccard_mean\": 0.687, \"re_full_rho_sj\": 0.2343, \"re_full_rho_fk\": 0.1835, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3716, \"re_cond_rho_fk\": 0.2533, \"re_cond_n\": 301, \"re_sj_beats_fk_full\": true, \"re_sj_beats_fk_cond\": true, \"re_rho_advantage\": 0.0508, \"re_sample_f1_mean\": 0.3782, \"re_sample_f1_std\": 0.3845, \"re_sample_f1_pct_zero\": 42.4, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 96, \"parse_failures\": 0, \"verdict\": \"FAIL\", \"verdict_note\": \"RE full rho_sj=0.234 < 0.40; RE cond rho_sj=0.372 passes conditional but not full threshold\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T09:47:06.597Z\"}, \"e1_component_wise_re_sj\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:15:17.262Z\", \"updated_at\": \"2026-05-14T09:23:38.818Z\", \"spec\": {\"hypothesis\": \"RE SJ 乘性惩罚是 root cause：分解后 head_sj ρ ≈ NER ρ (~0.38)，tail_sj 和乘性组合拖低整体 ρ\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 397, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Component-wise decomposition: head_sj, tail_sj, type_match 分别计算 Spearman ρ vs per-instance RE F1\", \"command\": \"python3 code/analyze_component_wise_re.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/e1_component_analysis.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"full_head_sj_rho\": 0.21, \"full_tail_sj_rho\": 0.201, \"full_type_match_rho\": 0.201, \"full_multiplicative_rho\": 0.244, \"full_additive_rho\": 0.243, \"full_fleiss_kappa_rho\": 0.278, \"cond_head_sj_rho\": 0.27, \"cond_tail_sj_rho\": 0.259, \"cond_type_match_rho\": 0.252, \"cond_multiplicative_rho\": 0.316, \"cond_additive_rho\": 0.306, \"cond_fleiss_kappa_rho\": 0.307, \"n_full\": 397, \"n_conditional\": 313, \"diagnosis\": \"head_sj rho=0.210 FAR from NER rho=0.383. Multiplicative penalty hypothesis REJECTED. Problem is fundamental: span-level SJ lacks discriminative power for RE.\"}, \"completed_at\": \"2026-05-14T09:22:26.155Z\"}, \"mvp_pilot_004\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:51:38.203Z\", \"updated_at\": \"2026-05-14T09:10:40.918Z\", \"spec\": {\"hypothesis\": \"With improved RE quality (F1=41.8%), structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa, reaching rho_sj >= 0.40 on RE\", \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2 (ft_002_v2 final)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_002_v2\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment + max_tokens=1024 + gold-empty filter + conditional rho\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/mvp_pilot_004 --num_test 551 --seed 42 --tensor_parallel 1\", \"gpu\": \"cuda:0\", \"pid\": 31041, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/mvp_pilot_004.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\"}, \"metrics\": {\"ner_greedy_f1\": 0.6671, \"ner_oracle_f1\": 0.7756, \"ner_headroom\": 0.1085, \"ner_fleiss_kappa_mean\": 0.4048, \"ner_soft_jaccard_mean\": 0.7008, \"ner_full_rho_fk\": 0.259, \"ner_full_rho_sj\": 0.3825, \"ner_full_n\": 529, \"ner_cond_rho_fk\": 0.2352, \"ner_cond_rho_sj\": 0.3762, \"ner_cond_n\": 508, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_sample_f1_mean\": 0.6084, \"ner_sample_f1_std\": 0.3174, \"ner_sample_f1_pct_zero\": 12.19, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 21, \"re_greedy_f1\": 0.4208, \"re_oracle_f1\": 0.5882, \"re_headroom\": 0.1674, \"re_fleiss_kappa_mean\": 0.2996, \"re_soft_jaccard_mean\": 0.6114, \"re_full_rho_fk\": 0.2782, \"re_full_rho_sj\": 0.2441, \"re_full_n\": 397, \"re_cond_rho_fk\": 0.3067, \"re_cond_rho_sj\": 0.3161, \"re_cond_n\": 313, \"re_sj_beats_fk_full\": false, \"re_sj_beats_fk_cond\": true, \"re_sample_f1_mean\": 0.3612, \"re_sample_f1_std\": 0.383, \"re_sample_f1_pct_zero\": 44.3, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 84, \"parse_failures\": 0, \"verdict\": \"FAIL\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T09:10:40.918Z\"}, \"ft_002_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:28:40.861Z\", \"updated_at\": \"2026-05-14T08:51:32.405Z\", \"spec\": {\"hypothesis\": \"Extended training (5 epochs, LoRA r=32) with OOM fix improves RE F1 above 40% threshold\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/llmfactory_train.json\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"LoRA r=32 alpha=64, 5 epochs, batch=2 grad_accum=8 gradient_checkpointing=true\", \"gpu\": \"cuda:1\", \"pid\": 24947, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/ft_002v2_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora-v2\", \"command\": \"CUDA_VISIBLE_DEVICES=1 llamafactory-cli train train_config_v2.yaml\"}, \"conclusion\": \"success\", \"metrics\": {\"epoch\": 5, \"train_loss\": 0.0806, \"eval_loss\": 0.089, \"train_runtime\": \"28m41s\", \"train_samples_per_second\": 5.407, \"train_steps_per_second\": 0.34, \"total_steps\": 585, \"checkpoints\": [\"checkpoint-400\", \"checkpoint-500\", \"checkpoint-585\"], \"gate0_final_ner_f1\": 0.6615, \"gate0_final_re_f1\": 0.4177, \"gate0_final_parse_failures\": 0, \"gate0_final_ner_pass\": true, \"gate0_final_re_pass\": true, \"gate0_final_pass\": true, \"gate0_ckpt400_ner_f1\": 0.6475, \"gate0_ckpt400_re_f1\": 0.3793, \"gate0_ckpt400_parse_failures\": 0, \"gate0_ckpt400_verdict\": \"FAIL\", \"gate0_ckpt400_re_sample_f1_pct_zero\": 58.8, \"gate0_ckpt400_warning\": \">30% samples F1=0\"}, \"completed_at\": \"2026-05-14T08:51:32.405Z\"}, \"mvp_pilot_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:02:16.991Z\", \"updated_at\": \"2026-05-14T08:48:14.040Z\", \"spec\": {\"hypothesis\": \"Structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa on fine-tuned Qwen3-8B SciERC\", \"model_name\": \"Qwen3-8B-SciERC-LoRA (ft_001)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment + gold-empty filter + conditional rho\", \"gpu\": \"cuda:0\", \"note\": \"Rerun of mvp_pilot_001 which crashed silently\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-lora --data_dir data/scierc --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 512 --output_dir output/mvp_pilot_001 --num_test 551 --seed 42 --tensor_parallel 1\", \"failure_reason\": \"Worker used LoRA adapter path instead of merged model path; vLLM cannot load LoRA adapter directly\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T08:48:14.040Z\"}, \"ft_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:39:18.640Z\", \"updated_at\": \"2026-05-14T08:28:00.590Z\", \"spec\": {\"hypothesis\": \"Extended training (5 epochs, LoRA r=32) improves RE F1 above 40% threshold\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/llmfactory_train.json\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"LoRA r=32 alpha=64, 5 epochs, relation direction hint\", \"command\": \"llamafactory-cli train /root/autodl-tmp/struct_self_consist_ie/train_config_v2.yaml\", \"gpu\": \"cuda:1\", \"pid\": 19666, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/ft_002_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora-v2\", \"total_steps\": 585, \"trainable_params\": \"87.3M\", \"estimated_runtime\": \"29min\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T08:02:30.390Z\", \"metrics\": {\"last_step\": 70, \"total_steps\": 585, \"progress_pct\": 11.97, \"last_loss\": 0.1134, \"last_lr\": 0.00019982, \"elapsed\": \"3m32s\", \"failure_reason\": \"OOM at step 73, batch_size=4 too large for 32GB RTX 5090\"}}, \"ft_001\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T06:04:28.030Z\", \"updated_at\": \"2026-05-14T08:27:58.182Z\", \"spec\": {\"hypothesis\": \"Fine-tuned Qwen3-8B on SciERC UIE can achieve NER F1 >= 73 and serve as base model for structural consistency MVP\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"method\": \"LoRA r=16 alpha=32\", \"framework\": \"LLaMA Factory 0.9.4\", \"command\": \"sft training qwen3-8b on scierc with lora\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/ft_001_train.log\", \"train_loss\": 0.1099, \"eval_loss\": 0.0771, \"epoch\": 3, \"train_runtime\": \"0:17:49\", \"note\": \"gate0: NER PASS 60.4% / RE FAIL 33.8%\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T06:30:32.889Z\", \"metrics\": {\"train_loss\": 0.1099, \"eval_loss\": 0.0771, \"gate0_ner_f1_strict\": 0.1143, \"gate0_re_f1_strict\": 0.0125, \"gate0_ner_f1_text\": 0.606, \"gate0_re_f1_text\": 0.3392, \"gate0_offset_accuracy\": 0.1665, \"gate0_parse_failures\": 43, \"gate0_pass\": false, \"gate0_realigned_ner_f1\": 0.6045, \"gate0_realigned_re_f1\": 0.338, \"gate0_realigned_entity_offset_accuracy\": 1, \"gate0_realigned_relation_offset_accuracy\": 1, \"gate0_realigned_ner_pass\": true, \"gate0_realigned_re_pass\": false, \"gate0_realigned_pass\": false, \"gate0_ner_f1_delta_realign\": 0.4901, \"gate0_re_f1_delta_realign\": 0.3255, \"verdict_note\": \"partial: NER PASS (60.4%) / RE FAIL (33.8% < 40%)\"}}, \"mvp_pilot_003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:21:09.847Z\", \"updated_at\": \"2026-05-14T08:21:44.983Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path /root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged --data_dir /root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir /root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_003 --num_test 551 --seed 42 --tensor_parallel 1\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged\", \"seed\": 42}, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/mvp_pilot_003.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_003\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T08:21:30.319Z\", \"metrics\": {\"ner_greedy_f1\": 0.6362, \"ner_oracle_f1\": 0.792, \"ner_headroom\": 0.1559, \"ner_fleiss_kappa_mean\": 0.2488, \"ner_soft_jaccard_mean\": 0.5066, \"ner_full_rho_sj\": 0.3808, \"ner_full_rho_fk\": 0.3362, \"ner_full_p_sj\": 1.07e-19, \"ner_full_p_fk\": 1.93e-15, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3836, \"ner_cond_rho_fk\": 0.3187, \"ner_cond_p_sj\": 1.83e-19, \"ner_cond_p_fk\": 1.33e-13, \"ner_cond_n\": 514, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_rho_advantage\": 0.0446, \"ner_sample_f1_mean\": 0.5153, \"ner_sample_f1_std\": 0.3334, \"ner_sample_f1_pct_zero\": 19.9, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 15, \"re_greedy_f1\": 0.3774, \"re_oracle_f1\": 0.5939, \"re_headroom\": 0.2165, \"re_fleiss_kappa_mean\": 0.0879, \"re_soft_jaccard_mean\": 0.3958, \"re_full_rho_sj\": 0.2367, \"re_full_rho_fk\": 0.2221, \"re_full_p_sj\": 1.85e-06, \"re_full_p_fk\": 7.92e-06, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3004, \"re_cond_rho_fk\": 0.2374, \"re_cond_p_sj\": 2.25e-08, \"re_cond_p_fk\": 1.19e-05, \"re_cond_n\": 333, \"re_sj_beats_fk_full\": true, \"re_sj_beats_fk_cond\": true, \"re_rho_advantage\": 0.0146, \"re_sample_f1_mean\": 0.1977, \"re_sample_f1_std\": 0.3251, \"re_sample_f1_pct_zero\": 67.6, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 64, \"parse_failures_stochastic\": 0, \"parse_failures_greedy\": 0, \"total_stochastic_samples\": 4408, \"total_greedy\": 551, \"verdict\": \"FAIL\", \"verdict_reason\": \"RE full rho_sj=0.2367 < 0.40 threshold; strong signal exists but below PASS bar\"}}, \"mvp_pilot_001\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:39:16.313Z\", \"updated_at\": \"2026-05-14T08:05:34.348Z\", \"spec\": {\"hypothesis\": \"Structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa on fine-tuned Qwen3-8B SciERC\", \"model_name\": \"qwen3-8b-scierc-merged\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/test.jsonl\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/mvp_pilot.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_001.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T07:52:47.006Z\", \"metrics\": {\"ner_greedy_f1\": 0.611, \"ner_oracle_f1\": 0.78, \"ner_headroom\": 0.169, \"ner_fleiss_kappa_mean\": 0.2449, \"ner_soft_jaccard_mean\": 0.5041, \"ner_full_rho_sj\": 0.3616, \"ner_full_rho_fk\": 0.3515, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3688, \"ner_cond_rho_fk\": 0.3569, \"ner_cond_n\": 510, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_sample_f1_pct_zero\": 20.4, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 19, \"re_greedy_f1\": 0.355, \"re_oracle_f1\": 0.572, \"re_headroom\": 0.217, \"re_fleiss_kappa_mean\": 0.0681, \"re_soft_jaccard_mean\": 0.3635, \"re_full_rho_sj\": 0.2535, \"re_full_rho_fk\": 0.2885, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3515, \"re_cond_rho_fk\": 0.3107, \"re_cond_n\": 320, \"re_sj_beats_fk_full\": false, \"re_sj_beats_fk_cond\": true, \"re_sample_f1_pct_zero\": 58.3, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 77, \"parse_failures_stochastic\": 164, \"parse_failures_greedy\": 29, \"total_stochastic_samples\": 4408, \"total_greedy\": 551, \"verdict\": \"FAIL\", \"verdict_reason\": \"RE full rho_sj=0.2535 < 0.40; SJ does not beat FK on RE full set\"}}}, \"count\": 272, \"total\": 272, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.7139}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 13_

<details><summary>Logged reasoning block</summary>

```text
The registry is very large. Let me filter it more specifically - I need to find experiments related to α_crit, FewNERD T=1.0, CoNLL T=1.0, SciERC T=1.0. Let me use jq to extract relevant experiments. Let me also search for the specific seeds mentioned.

The α_crit table says:
- FewNERD: 3 seeds (123, 456, 789)
- CoNLL: 2 seeds (123, 456)
- SciERC: 2 seeds (456, 789)


The reviewer mentions MF4v2 uses seeds (42, 123, 456), which creates a seed mismatch issue. There's also a potential bug with greedy_macro_f1 versus micro_f1 that I need to investigate. Let me query the registry more carefully and check the server logs to understand what's actually happening.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "fb8c6847-c7a4-4568-b282-88dc44b62785",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LDmwpFHyS59fPMZevbHbsq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1939,
      "cache_read_input_tokens": 26785,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1939
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

_source line 14_

注册表太大，用过滤查询和 SSH 并行检查。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "cd971ce2-323d-4d68-b4c6-64152b5c9a52",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LDmwpFHyS59fPMZevbHbsq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1939,
      "cache_read_input_tokens": 26785,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1939
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

_source line 15_

<details open><summary>🔧 Tool call — Bash · `toolu_014wvVa2YegiPevEzfuNVVDH`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/6986ae13-ffc9-44c1-9a46-461b58b60630/tool-results/mcp-agent-ml-research-read_registry-1779355628042.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\n# Find experiments related to alpha_crit, T=1.0, entity construction, fewnerd/conll/scierc\nkeywords = ['alpha', 'crit', 't10', 't1.0', 'entity_construct', 'fewnerd', 'conll', 'scierc', 'mf4', 'pilot']\nfor exp in result:\n    exp_id = exp.get('exp_id', '')\n    desc = exp.get('description', '')\n    tags = exp.get('tags', [])\n    combined = (exp_id + ' ' + desc + ' ' + ' '.join(tags if tags else [])).lower()\n    if any(k in combined for k in keywords):\n        print(f\\\"=== {exp_id} ===\\\")\n        print(f\\\"  status: {exp.get('status')}\\\")\n        print(f\\\"  description: {desc[:200]}\\\")\n        print(f\\\"  tags: {tags}\\\")\n        config = exp.get('config', {})\n        if config:\n            seed = config.get('seed', config.get('seeds', 'N/A'))\n            print(f\\\"  seed: {seed}\\\")\n            print(f\\\"  dataset: {config.get('dataset', 'N/A')}\\\")\n            print(f\\\"  temperature: {config.get('temperature', config.get('T', 'N/A'))}\\\")\n        metrics = exp.get('metrics', {})\n        if metrics:\n            relevant = {k:v for k,v in metrics.items() if any(x in k.lower() for x in ['greedy', 'f1', 'mv', 'alpha', 'degen'])}\n            if relevant:\n                print(f\\\"  metrics: {relevant}\\\")\n        print(f\\\"  output_dir: {exp.get('output_dir', config.get('output_dir', 'N/A') if config else 'N/A')}\\\")\n        print()\n\" 2>&1 | head -500",
  "description": "Filter registry for alpha_crit related experiments",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "a1c9b2b1-87ac-44cf-9ca3-555aea44be00",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LDmwpFHyS59fPMZevbHbsq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1939,
      "cache_read_input_tokens": 26785,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1939
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

_source line 16 · 2026-05-21T09:27:23.698Z_

<details><summary>↩ Tool result · `toolu_014wvVa2YegiPevEzfuNVVDH`</summary>

```text
Traceback (most recent call last):
  File "&lt;string>", line 8, in &lt;module>
    exp_id = exp.get('exp_id', '')
             ^^^^^^^
AttributeError: 'str' object has no attribute 'get'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "ef0de841-6f88-4938-b9aa-b1c05683dba1",
  "tool_use_result": {
    "stdout": "Traceback (most recent call last):\n  File \"&lt;string>\", line 8, in &lt;module>\n    exp_id = exp.get('exp_id', '')\n             ^^^^^^^\nAttributeError: 'str' object has no attribute 'get'",
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

_source line 17_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01A8LHcHxAZoEHby4eiAHh5y`</summary>

```json
{
  "server": "autodl-5090",
  "command": "ls -la /root/autodl-tmp/struct_self_consist_ie/output/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "6b9711c2-b94b-4a07-bfc7-c85a97657936",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LDmwpFHyS59fPMZevbHbsq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1939,
      "cache_read_input_tokens": 26785,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1939
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

_source line 18 · 2026-05-21T09:27:24.838Z_

<details><summary>↩ Tool result · `toolu_01A8LHcHxAZoEHby4eiAHh5y`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"total 22812\\ndrwxr-xr-x 214 root root   16384 May 21 17:08 .\\ndrwxr-xr-x  17 root root    8192 May 21 13:13 ..\\n-rw-r--r--   1 root root    4767 May 17 22:19 adalp_analysis_results.json\\n-rw-r--r--   1 root root    3142 May 19 01:53 adaptive_temperature_results.json\\ndrwxr-xr-x   2 root root      85 May 16 00:37 analysis_epsilon_sweep\\n-rw-r--r--   1 root root    7926 May 15 20:56 analysis_fk_bootstrap_ci.json\\n-rw-r--r--   1 root root    5824 May 15 21:16 analysis_fk_bootstrap_per_instance.json\\n-rw-r--r--   1 root root  150381 May 15 21:15 analysis_lp_range_cdf.json\\n-rw-r--r--   1 root root    3197 May 15 21:15 analysis_lp_range_cdf_n16_3seed.json\\n-rw-r--r--   1 root root    1852 May 19 00:30 analysis_mbr_selection.json\\n-rw-r--r--   1 root root   10542 May 15 20:46 analysis_multiseed_selection_f1.json\\ndrwxr-xr-x   2 root root    4096 May 16 00:50 analysis_round8\\n-rw-r--r--   1 root root   20864 May 15 21:14 analysis_scierc_n16_3seed_selection_f1.json\\n-rw-r--r--   1 root root   30781 May 15 21:26 analysis_scierc_n16_3seed_selection_f1_merged.json\\n-rw-r--r--   1 root root    9919 May 15 21:26 analysis_scierc_re_n16_3seed_selection_f1.json\\n-rw-r--r--   1 root root    7621 May 15 22:57 analysis_unified_rho_full.json\\n-rw-r--r--   1 root root    2131 May 19 07:41 analyze_s789_rerun.log\\n-rw-r--r--   1 root root   10262 May 20 17:08 b5_cross_model_construction.py\\n-rw-r--r--   1 root root    3808 May 20 17:09 b5_cross_model_results.json\\ndrwxr-xr-x   2 root root      44 May 20 17:08 b7_adaptive_budget\\ndrwxr-xr-x   2 root root      69 May 15 05:17 bootstrap_ci_nscaling\\n-rw-r--r--   1 root root   18675 May 15 06:05 bootstrap_ci_summary.json\\n-rw-r--r--   1 root root    1977 May 15 06:06 bootstrap_ci_tables.tex\\n-rw-r--r--   1 root root   23857 May 17 22:20 calibration_baseline_results.json\\n-rw-r--r--   1 root root     987 May 19 02:03 ccs_selection_report.md\\n-rw-r--r--   1 root root    5228 May 19 02:03 ccs_selection_results.json\\ndrwxr-xr-x   2 root root      45 May 19 06:03 claim_audit\\n-rw-r--r--   1 root root    2098 May 14 20:48 conditional_filter_diagnosis.json\\ndrwxr-xr-x   2 root root      10 May 21 13:09 conll_mf4_seed123\\ndrwxr-xr-x   2 root root      10 May 21 13:09 conll_mf4_seed456\\ndrwxr-xr-x   2 root root      10 May 21 12:50 conll_n16_s123\\ndrwxr-xr-x   2 root root      10 May 21 12:51 conll_n16_s456\\ndrwxr-xr-x   2 root root      10 May 21 13:05 conll_n16_seed123_v2\\ndrwxr-xr-x   2 root root      10 May 21 13:05 conll_n16_seed456_v2\\ndrwxr-xr-x   2 root root      56 May 20 06:35 construction_variants\\ndrwxr-xr-x   2 root root      54 May 16 15:25 d108_greedy_f1\\ndrwxr-xr-x   2 root root      85 May 16 15:47 d108_lp_vc_combination\\ndrwxr-xr-x   2 root root      90 May 16 15:08 d108_mbr_within_rho\\ndrwxr-xr-x   2 root root     166 May 16 15:50 d108_q4q5\\ndrwxr-xr-x   2 root root      90 May 16 16:12 d110_4b_degeneracy\\ndrwxr-xr-x   2 root root      37 May 16 17:47 d112_disk_cleanup\\ndrwxr-xr-x   2 root root      85 May 16 17:26 d112_hybrid_strategy\\ndrwxr-xr-x   2 root root      94 May 16 17:10 d112_mf3_random_single\\ndrwxr-xr-x   2 root root    4096 May 16 17:48 d112_table2_fix\\ndrwxr-xr-x   2 root root      96 May 16 19:29 d114_auroc_investigation\\ndrwxr-xr-x   2 root root      74 May 18 21:28 d140_oracle_gated\\ndrwxr-xr-x   2 root root      55 May 18 21:31 d141_conditional_decomp\\ndrwxr-xr-x   2 root root      87 May 18 21:32 d141_degeneracy_scatter\\ndrwxr-xr-x   2 root root      86 May 18 21:29 d141_entity_merge\\n-rw-r--r--   1 root root   31273 May 18 14:03 dals_analysis.json\\n-rw-r--r--   1 root root    1735 May 18 17:31 dals_cross_model.json\\n-rw-r--r--   1 root root    4479 May 18 14:48 dals_hardening_results.json\\ndrwxr-xr-x   2 root root    4096 May 18 14:32 deberta_verifier\\ndrwxr-xr-x   3 root root    4096 May 18 15:21 deberta_verifier_5fold\\n-rw-r--r--   1 root root    5259 May 19 07:37 debug_sj_variance.log\\n-rw-r--r--   1 root root    1111 May 19 07:37 debug_sj_variance_results.json\\ndrwxr-xr-x   2 root root      45 May 19 15:26 decomposition_regr\\n\\n... [截断: 输出过长，省略 15999 字符] ...\\n\\n  58 May 19 11:09 llama_fewnerd_s123\\ndrwxr-xr-x   2 root root      58 May 19 11:08 llama_fewnerd_s42\\ndrwxr-xr-x   2 root root      58 May 19 11:08 llama_fewnerd_s456\\ndrwxr-xr-x   2 root root      36 May 14 20:25 logprob_diagnosis\\ndrwxr-xr-x   2 root root      34 May 15 03:31 loo_sj_cross_dataset\\n-rw-r--r--   1 root root    4652 May 18 08:57 lp_rank_comparison.py\\n-rw-r--r--   1 root root     715 May 18 08:57 lp_rank_comparison_results.json\\n-rw-r--r--   1 root root    1038 May 19 00:46 mbr_selection_results.json\\n-rw-r--r--   1 root root     323 May 19 01:39 merge_conll.log\\ndrwxr-xr-x   2 root root      51 May 21 10:03 multi_model_correlation\\n-rw-r--r--   1 root root   18926 May 15 20:53 multiseed_selection_f1.json\\ndrwxr-xr-x   2 root root      58 May 14 15:51 mvp_pilot_001\\n-rw-r--r--   1 root root  104190 May 14 15:51 mvp_pilot_001.log\\ndrwxr-xr-x   2 root root      58 May 14 16:20 mvp_pilot_003\\ndrwxr-xr-x   2 root root     187 May 14 19:17 mvp_pilot_004\\ndrwxr-xr-x   2 root root      58 May 14 17:19 mvp_pilot_005\\n-rw-r--r--   1 root root    1895 May 15 19:37 n16_3seed_5signal_results.json\\n-rw-r--r--   1 root root    4263 May 15 19:37 n16_3seed_analysis.py\\n-rw-r--r--   1 root root    3256 May 15 03:00 n16_5signal_results.json\\n-rw-r--r--   1 root root    3258 May 15 03:02 n8_5signal_results.json\\n-rw-r--r--   1 root root    3437 May 18 13:36 n_scaling_gf_maxlp.json\\ndrwxr-xr-x   2 root root      47 May 19 05:52 paper_f1_audit\\n-rw-r--r--   1 root root    6482 May 19 05:52 paper_f1_audit_script.py\\ndrwxr-xr-x   2 root root    4096 May 19 09:26 prescriptive_analysis\\ndrwxr-xr-x   2 root root     125 May 17 16:37 r17_analyses\\ndrwxr-xr-x   2 root root      55 May 18 21:38 r21_q1_alignment\\ndrwxr-xr-x   2 root root      37 May 18 21:40 r21_w5_lp_rho_audit\\n-rw-r--r--   1 root root    5404 May 18 12:21 recompute_tab_fewnerd_results.json\\ndrwxr-xr-x   2 root root    4096 May 15 23:32 review_round2\\ndrwxr-xr-x   2 root root     169 May 15 15:38 review_round4\\ndrwxr-xr-x   2 root root    4096 May 16 06:42 review_round8\\ndrwxr-xr-x   6 root root    4096 May 16 12:46 review_round9_experiments\\n-rw-r--r--   1 root root    3732 May 15 21:23 rho_audit_results.json\\n-rw-r--r--   1 root root    6516 May 19 05:43 scatter_v2_data.json\\ndrwxr-xr-x   2 root root      10 May 21 17:08 scierc_mf4v2_seed42\\n-rw-r--r--   1 root root    3219 May 16 04:03 selection_f1_4b_results.json\\n-rw-r--r--   1 root root     807 May 20 17:06 sj_8b_qwen3_ft_progress.log\\n-rw-r--r--   1 root root    7000 May 20 17:06 sj_8b_qwen3_ft_results.json\\ndrwxr-xr-x   2 root root    4096 May 18 14:53 statistical_hardening\\ndrwxr-xr-x   2 root root      34 May 19 15:07 supervised_verifier_upgrade\\n-rw-r--r--   1 root root    4738 May 19 15:14 supervised_verifier_upgrade.log\\n-rw-r--r--   1 root root     359 May 19 06:55 supplement_degen_results.json\\n-rw-r--r--   1 root root    3327 May 18 17:31 task1_within_rho.py\\n-rw-r--r--   1 root root    3710 May 18 17:31 task2_dals_cross_model.py\\n-rw-r--r--   1 root root    2184 May 18 17:31 task3_llama_n16_check.py\\ndrwxr-xr-x   2 root root    4096 May 18 18:45 token_lp_aggregator\\n-rw-r--r--   1 root root    5056 May 18 18:45 token_lp_aggregator_fewnerd.log\\n-rw-r--r--   1 root root       0 May 18 18:39 token_lp_aggregator_scierc.log\\n-rw-r--r--   1 root root    5074 May 18 18:44 token_lp_aggregator_scierc_3ep.log\\n-rw-r--r--   1 root root    5077 May 18 18:42 token_lp_aggregator_scierc_v2.log\\ndrwxr-xr-x   2 root root     111 May 21 10:24 unified_degeneracy_audit\\ndrwxr-xr-x   2 root root      44 May 19 02:43 unified_metrics_regression\\ndrwxr-xr-x   2 root root      76 May 19 05:30 unified_oracle_audit\\n-rw-r--r--   1 root root    1314 May 18 12:42 unified_tab_fewnerd_maxlp.json\\n-rw-r--r--   1 root root     807 May 20 17:02 vc_8b_qwen3_ft_progress.log\\n-rw-r--r--   1 root root    7810 May 20 17:02 vc_8b_qwen3_ft_results.json\\n-rw-r--r--   1 root root    8953 May 16 12:56 vc_quartile_analysis.json\\n-rw-r--r--   1 root root    1241 May 18 17:31 within_instance_rho_table.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.94}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "7948685d-81eb-4d66-afe2-a4e1568ad1df",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"total 22812\\\\ndrwxr-xr-x 214 root root   16384 May 21 17:08 .\\\\ndrwxr-xr-x  17 root root    8192 May 21 13:13 ..\\\\n-rw-r--r--   1 root root    4767 May 17 22:19 adalp_analysis_results.json\\\\n-rw-r--r--   1 root root    3142 May 19 01:53 adaptive_temperature_results.json\\\\ndrwxr-xr-x   2 root root      85 May 16 00:37 analysis_epsilon_sweep\\\\n-rw-r--r--   1 root root    7926 May 15 20:56 analysis_fk_bootstrap_ci.json\\\\n-rw-r--r--   1 root root    5824 May 15 21:16 analysis_fk_bootstrap_per_instance.json\\\\n-rw-r--r--   1 root root  150381 May 15 21:15 analysis_lp_range_cdf.json\\\\n-rw-r--r--   1 root root    3197 May 15 21:15 analysis_lp_range_cdf_n16_3seed.json\\\\n-rw-r--r--   1 root root    1852 May 19 00:30 analysis_mbr_selection.json\\\\n-rw-r--r--   1 root root   10542 May 15 20:46 analysis_multiseed_selection_f1.json\\\\ndrwxr-xr-x   2 root root    4096 May 16 00:50 analysis_round8\\\\n-rw-r--r--   1 root root   20864 May 15 21:14 analysis_scierc_n16_3seed_selection_f1.json\\\\n-rw-r--r--   1 root root   30781 May 15 21:26 analysis_scierc_n16_3seed_selection_f1_merged.json\\\\n-rw-r--r--   1 root root    9919 May 15 21:26 analysis_scierc_re_n16_3seed_selection_f1.json\\\\n-rw-r--r--   1 root root    7621 May 15 22:57 analysis_unified_rho_full.json\\\\n-rw-r--r--   1 root root    2131 May 19 07:41 analyze_s789_rerun.log\\\\n-rw-r--r--   1 root root   10262 May 20 17:08 b5_cross_model_construction.py\\\\n-rw-r--r--   1 root root    3808 May 20 17:09 b5_cross_model_results.json\\\\ndrwxr-xr-x   2 root root      44 May 20 17:08 b7_adaptive_budget\\\\ndrwxr-xr-x   2 root root      69 May 15 05:17 bootstrap_ci_nscaling\\\\n-rw-r--r--   1 root root   18675 May 15 06:05 bootstrap_ci_summary.json\\\\n-rw-r--r--   1 root root    1977 May 15 06:06 bootstrap_ci_tables.tex\\\\n-rw-r--r--   1 root root   23857 May 17 22:20 calibration_baseline_results.json\\\\n-rw-r--r--   1 root root     987 May 19 02:03 ccs_selection_report.md\\\\n-rw-r--r--   1 root root    5228 May 19 02:03 ccs_selection_results.json\\\\ndrwxr-xr-x   2 root root      45 May 19 06:03 claim_audit\\\\n-rw-r--r--   1 root root    2098 May 14 20:48 conditional_filter_diagnosis.json\\\\ndrwxr-xr-x   2 root root      10 May 21 13:09 conll_mf4_seed123\\\\ndrwxr-xr-x   2 root root      10 May 21 13:09 conll_mf4_seed456\\\\ndrwxr-xr-x   2 root root      10 May 21 12:50 conll_n16_s123\\\\ndrwxr-xr-x   2 root root      10 May 21 12:51 conll_n16_s456\\\\ndrwxr-xr-x   2 root root      10 May 21 13:05 conll_n16_seed123_v2\\\\ndrwxr-xr-x   2 root root      10 May 21 13:05 conll_n16_seed456_v2\\\\ndrwxr-xr-x   2 root root      56 May 20 06:35 construction_variants\\\\ndrwxr-xr-x   2 root root      54 May 16 15:25 d108_greedy_f1\\\\ndrwxr-xr-x   2 root root      85 May 16 15:47 d108_lp_vc_combination\\\\ndrwxr-xr-x   2 root root      90 May 16 15:08 d108_mbr_within_rho\\\\ndrwxr-xr-x   2 root root     166 May 16 15:50 d108_q4q5\\\\ndrwxr-xr-x   2 root root      90 May 16 16:12 d110_4b_degeneracy\\\\ndrwxr-xr-x   2 root root      37 May 16 17:47 d112_disk_cleanup\\\\ndrwxr-xr-x   2 root root      85 May 16 17:26 d112_hybrid_strategy\\\\ndrwxr-xr-x   2 root root      94 May 16 17:10 d112_mf3_random_single\\\\ndrwxr-xr-x   2 root root    4096 May 16 17:48 d112_table2_fix\\\\ndrwxr-xr-x   2 root root      96 May 16 19:29 d114_auroc_investigation\\\\ndrwxr-xr-x   2 root root      74 May 18 21:28 d140_oracle_gated\\\\ndrwxr-xr-x   2 root root      55 May 18 21:31 d141_conditional_decomp\\\\ndrwxr-xr-x   2 root root      87 May 18 21:32 d141_degeneracy_scatter\\\\ndrwxr-xr-x   2 root root      86 May 18 21:29 d141_entity_merge\\\\n-rw-r--r--   1 root root   31273 May 18 14:03 dals_analysis.json\\\\n-rw-r--r--   1 root root    1735 May 18 17:31 dals_cross_model.json\\\\n-rw-r--r--   1 root root    4479 May 18 14:48 dals_hardening_results.json\\\\ndrwxr-xr-x   2 root root    4096 May 18 14:32 deberta_verifier\\\\ndrwxr-xr-x   3 root root    4096 May 18 15:21 deberta_verifier_5fold\\\\n-rw-r--r--   1 root root    5259 May 19 07:37 debug_sj_variance.log\\\\n-rw-r--r--   1 root root    1111 May 19 07:37 debug_sj_variance_results.json\\\\ndrwxr-xr-x   2 root root      45 May 19 15:26 decomposition_regr\\\\n\\\\n... [截断: 输出过长，省略 15999 字符] ...\\\\n\\\\n  58 May 19 11:09 llama_fewnerd_s123\\\\ndrwxr-xr-x   2 root root      58 May 19 11:08 llama_fewnerd_s42\\\\ndrwxr-xr-x   2 root root      58 May 19 11:08 llama_fewnerd_s456\\\\ndrwxr-xr-x   2 root root      36 May 14 20:25 logprob_diagnosis\\\\ndrwxr-xr-x   2 root root      34 May 15 03:31 loo_sj_cross_dataset\\\\n-rw-r--r--   1 root root    4652 May 18 08:57 lp_rank_comparison.py\\\\n-rw-r--r--   1 root root     715 May 18 08:57 lp_rank_comparison_results.json\\\\n-rw-r--r--   1 root root    1038 May 19 00:46 mbr_selection_results.json\\\\n-rw-r--r--   1 root root     323 May 19 01:39 merge_conll.log\\\\ndrwxr-xr-x   2 root root      51 May 21 10:03 multi_model_correlation\\\\n-rw-r--r--   1 root root   18926 May 15 20:53 multiseed_selection_f1.json\\\\ndrwxr-xr-x   2 root root      58 May 14 15:51 mvp_pilot_001\\\\n-rw-r--r--   1 root root  104190 May 14 15:51 mvp_pilot_001.log\\\\ndrwxr-xr-x   2 root root      58 May 14 16:20 mvp_pilot_003\\\\ndrwxr-xr-x   2 root root     187 May 14 19:17 mvp_pilot_004\\\\ndrwxr-xr-x   2 root root      58 May 14 17:19 mvp_pilot_005\\\\n-rw-r--r--   1 root root    1895 May 15 19:37 n16_3seed_5signal_results.json\\\\n-rw-r--r--   1 root root    4263 May 15 19:37 n16_3seed_analysis.py\\\\n-rw-r--r--   1 root root    3256 May 15 03:00 n16_5signal_results.json\\\\n-rw-r--r--   1 root root    3258 May 15 03:02 n8_5signal_results.json\\\\n-rw-r--r--   1 root root    3437 May 18 13:36 n_scaling_gf_maxlp.json\\\\ndrwxr-xr-x   2 root root      47 May 19 05:52 paper_f1_audit\\\\n-rw-r--r--   1 root root    6482 May 19 05:52 paper_f1_audit_script.py\\\\ndrwxr-xr-x   2 root root    4096 May 19 09:26 prescriptive_analysis\\\\ndrwxr-xr-x   2 root root     125 May 17 16:37 r17_analyses\\\\ndrwxr-xr-x   2 root root      55 May 18 21:38 r21_q1_alignment\\\\ndrwxr-xr-x   2 root root      37 May 18 21:40 r21_w5_lp_rho_audit\\\\n-rw-r--r--   1 root root    5404 May 18 12:21 recompute_tab_fewnerd_results.json\\\\ndrwxr-xr-x   2 root root    4096 May 15 23:32 review_round2\\\\ndrwxr-xr-x   2 root root     169 May 15 15:38 review_round4\\\\ndrwxr-xr-x   2 root root    4096 May 16 06:42 review_round8\\\\ndrwxr-xr-x   6 root root    4096 May 16 12:46 review_round9_experiments\\\\n-rw-r--r--   1 root root    3732 May 15 21:23 rho_audit_results.json\\\\n-rw-r--r--   1 root root    6516 May 19 05:43 scatter_v2_data.json\\\\ndrwxr-xr-x   2 root root      10 May 21 17:08 scierc_mf4v2_seed42\\\\n-rw-r--r--   1 root root    3219 May 16 04:03 selection_f1_4b_results.json\\\\n-rw-r--r--   1 root root     807 May 20 17:06 sj_8b_qwen3_ft_progress.log\\\\n-rw-r--r--   1 root root    7000 May 20 17:06 sj_8b_qwen3_ft_results.json\\\\ndrwxr-xr-x   2 root root    4096 May 18 14:53 statistical_hardening\\\\ndrwxr-xr-x   2 root root      34 May 19 15:07 supervised_verifier_upgrade\\\\n-rw-r--r--   1 root root    4738 May 19 15:14 supervised_verifier_upgrade.log\\\\n-rw-r--r--   1 root root     359 May 19 06:55 supplement_degen_results.json\\\\n-rw-r--r--   1 root root    3327 May 18 17:31 task1_within_rho.py\\\\n-rw-r--r--   1 root root    3710 May 18 17:31 task2_dals_cross_model.py\\\\n-rw-r--r--   1 root root    2184 May 18 17:31 task3_llama_n16_check.py\\\\ndrwxr-xr-x   2 root root    4096 May 18 18:45 token_lp_aggregator\\\\n-rw-r--r--   1 root root    5056 May 18 18:45 token_lp_aggregator_fewnerd.log\\\\n-rw-r--r--   1 root root       0 May 18 18:39 token_lp_aggregator_scierc.log\\\\n-rw-r--r--   1 root root    5074 May 18 18:44 token_lp_aggregator_scierc_3ep.log\\\\n-rw-r--r--   1 root root    5077 May 18 18:42 token_lp_aggregator_scierc_v2.log\\\\ndrwxr-xr-x   2 root root     111 May 21 10:24 unified_degeneracy_audit\\\\ndrwxr-xr-x   2 root root      44 May 19 02:43 unified_metrics_regression\\\\ndrwxr-xr-x   2 root root      76 May 19 05:30 unified_oracle_audit\\\\n-rw-r--r--   1 root root    1314 May 18 12:42 unified_tab_fewnerd_maxlp.json\\\\n-rw-r--r--   1 root root     807 May 20 17:02 vc_8b_qwen3_ft_progress.log\\\\n-rw-r--r--   1 root root    7810 May 20 17:02 vc_8b_qwen3_ft_results.json\\\\n-rw-r--r--   1 root root    8953 May 16 12:56 vc_quartile_analysis.json\\\\n-rw-r--r--   1 root root    1241 May 18 17:31 within_instance_rho_table.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.94}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"total 22812\\ndrwxr-xr-x 214 root root   16384 May 21 17:08 .\\ndrwxr-xr-x  17 root root    8192 May 21 13:13 ..\\n-rw-r--r--   1 root root    4767 May 17 22:19 adalp_analysis_results.json\\n-rw-r--r--   1 root root    3142 May 19 01:53 adaptive_temperature_results.json\\ndrwxr-xr-x   2 root root      85 May 16 00:37 analysis_epsilon_sweep\\n-rw-r--r--   1 root root    7926 May 15 20:56 analysis_fk_bootstrap_ci.json\\n-rw-r--r--   1 root root    5824 May 15 21:16 analysis_fk_bootstrap_per_instance.json\\n-rw-r--r--   1 root root  150381 May 15 21:15 analysis_lp_range_cdf.json\\n-rw-r--r--   1 root root    3197 May 15 21:15 analysis_lp_range_cdf_n16_3seed.json\\n-rw-r--r--   1 root root    1852 May 19 00:30 analysis_mbr_selection.json\\n-rw-r--r--   1 root root   10542 May 15 20:46 analysis_multiseed_selection_f1.json\\ndrwxr-xr-x   2 root root    4096 May 16 00:50 analysis_round8\\n-rw-r--r--   1 root root   20864 May 15 21:14 analysis_scierc_n16_3seed_selection_f1.json\\n-rw-r--r--   1 root root   30781 May 15 21:26 analysis_scierc_n16_3seed_selection_f1_merged.json\\n-rw-r--r--   1 root root    9919 May 15 21:26 analysis_scierc_re_n16_3seed_selection_f1.json\\n-rw-r--r--   1 root root    7621 May 15 22:57 analysis_unified_rho_full.json\\n-rw-r--r--   1 root root    2131 May 19 07:41 analyze_s789_rerun.log\\n-rw-r--r--   1 root root   10262 May 20 17:08 b5_cross_model_construction.py\\n-rw-r--r--   1 root root    3808 May 20 17:09 b5_cross_model_results.json\\ndrwxr-xr-x   2 root root      44 May 20 17:08 b7_adaptive_budget\\ndrwxr-xr-x   2 root root      69 May 15 05:17 bootstrap_ci_nscaling\\n-rw-r--r--   1 root root   18675 May 15 06:05 bootstrap_ci_summary.json\\n-rw-r--r--   1 root root    1977 May 15 06:06 bootstrap_ci_tables.tex\\n-rw-r--r--   1 root root   23857 May 17 22:20 calibration_baseline_results.json\\n-rw-r--r--   1 root root     987 May 19 02:03 ccs_selection_report.md\\n-rw-r--r--   1 root root    5228 May 19 02:03 ccs_selection_results.json\\ndrwxr-xr-x   2 root root      45 May 19 06:03 claim_audit\\n-rw-r--r--   1 root root    2098 May 14 20:48 conditional_filter_diagnosis.json\\ndrwxr-xr-x   2 root root      10 May 21 13:09 conll_mf4_seed123\\ndrwxr-xr-x   2 root root      10 May 21 13:09 conll_mf4_seed456\\ndrwxr-xr-x   2 root root      10 May 21 12:50 conll_n16_s123\\ndrwxr-xr-x   2 root root      10 May 21 12:51 conll_n16_s456\\ndrwxr-xr-x   2 root root      10 May 21 13:05 conll_n16_seed123_v2\\ndrwxr-xr-x   2 root root      10 May 21 13:05 conll_n16_seed456_v2\\ndrwxr-xr-x   2 root root      56 May 20 06:35 construction_variants\\ndrwxr-xr-x   2 root root      54 May 16 15:25 d108_greedy_f1\\ndrwxr-xr-x   2 root root      85 May 16 15:47 d108_lp_vc_combination\\ndrwxr-xr-x   2 root root      90 May 16 15:08 d108_mbr_within_rho\\ndrwxr-xr-x   2 root root     166 May 16 15:50 d108_q4q5\\ndrwxr-xr-x   2 root root      90 May 16 16:12 d110_4b_degeneracy\\ndrwxr-xr-x   2 root root      37 May 16 17:47 d112_disk_cleanup\\ndrwxr-xr-x   2 root root      85 May 16 17:26 d112_hybrid_strategy\\ndrwxr-xr-x   2 root root      94 May 16 17:10 d112_mf3_random_single\\ndrwxr-xr-x   2 root root    4096 May 16 17:48 d112_table2_fix\\ndrwxr-xr-x   2 root root      96 May 16 19:29 d114_auroc_investigation\\ndrwxr-xr-x   2 root root      74 May 18 21:28 d140_oracle_gated\\ndrwxr-xr-x   2 root root      55 May 18 21:31 d141_conditional_decomp\\ndrwxr-xr-x   2 root root      87 May 18 21:32 d141_degeneracy_scatter\\ndrwxr-xr-x   2 root root      86 May 18 21:29 d141_entity_merge\\n-rw-r--r--   1 root root   31273 May 18 14:03 dals_analysis.json\\n-rw-r--r--   1 root root    1735 May 18 17:31 dals_cross_model.json\\n-rw-r--r--   1 root root    4479 May 18 14:48 dals_hardening_results.json\\ndrwxr-xr-x   2 root root    4096 May 18 14:32 deberta_verifier\\ndrwxr-xr-x   3 root root    4096 May 18 15:21 deberta_verifier_5fold\\n-rw-r--r--   1 root root    5259 May 19 07:37 debug_sj_variance.log\\n-rw-r--r--   1 root root    1111 May 19 07:37 debug_sj_variance_results.json\\ndrwxr-xr-x   2 root root      45 May 19 15:26 decomposition_regr\\n\\n... [截断: 输出过长，省略 15999 字符] ...\\n\\n  58 May 19 11:09 llama_fewnerd_s123\\ndrwxr-xr-x   2 root root      58 May 19 11:08 llama_fewnerd_s42\\ndrwxr-xr-x   2 root root      58 May 19 11:08 llama_fewnerd_s456\\ndrwxr-xr-x   2 root root      36 May 14 20:25 logprob_diagnosis\\ndrwxr-xr-x   2 root root      34 May 15 03:31 loo_sj_cross_dataset\\n-rw-r--r--   1 root root    4652 May 18 08:57 lp_rank_comparison.py\\n-rw-r--r--   1 root root     715 May 18 08:57 lp_rank_comparison_results.json\\n-rw-r--r--   1 root root    1038 May 19 00:46 mbr_selection_results.json\\n-rw-r--r--   1 root root     323 May 19 01:39 merge_conll.log\\ndrwxr-xr-x   2 root root      51 May 21 10:03 multi_model_correlation\\n-rw-r--r--   1 root root   18926 May 15 20:53 multiseed_selection_f1.json\\ndrwxr-xr-x   2 root root      58 May 14 15:51 mvp_pilot_001\\n-rw-r--r--   1 root root  104190 May 14 15:51 mvp_pilot_001.log\\ndrwxr-xr-x   2 root root      58 May 14 16:20 mvp_pilot_003\\ndrwxr-xr-x   2 root root     187 May 14 19:17 mvp_pilot_004\\ndrwxr-xr-x   2 root root      58 May 14 17:19 mvp_pilot_005\\n-rw-r--r--   1 root root    1895 May 15 19:37 n16_3seed_5signal_results.json\\n-rw-r--r--   1 root root    4263 May 15 19:37 n16_3seed_analysis.py\\n-rw-r--r--   1 root root    3256 May 15 03:00 n16_5signal_results.json\\n-rw-r--r--   1 root root    3258 May 15 03:02 n8_5signal_results.json\\n-rw-r--r--   1 root root    3437 May 18 13:36 n_scaling_gf_maxlp.json\\ndrwxr-xr-x   2 root root      47 May 19 05:52 paper_f1_audit\\n-rw-r--r--   1 root root    6482 May 19 05:52 paper_f1_audit_script.py\\ndrwxr-xr-x   2 root root    4096 May 19 09:26 prescriptive_analysis\\ndrwxr-xr-x   2 root root     125 May 17 16:37 r17_analyses\\ndrwxr-xr-x   2 root root      55 May 18 21:38 r21_q1_alignment\\ndrwxr-xr-x   2 root root      37 May 18 21:40 r21_w5_lp_rho_audit\\n-rw-r--r--   1 root root    5404 May 18 12:21 recompute_tab_fewnerd_results.json\\ndrwxr-xr-x   2 root root    4096 May 15 23:32 review_round2\\ndrwxr-xr-x   2 root root     169 May 15 15:38 review_round4\\ndrwxr-xr-x   2 root root    4096 May 16 06:42 review_round8\\ndrwxr-xr-x   6 root root    4096 May 16 12:46 review_round9_experiments\\n-rw-r--r--   1 root root    3732 May 15 21:23 rho_audit_results.json\\n-rw-r--r--   1 root root    6516 May 19 05:43 scatter_v2_data.json\\ndrwxr-xr-x   2 root root      10 May 21 17:08 scierc_mf4v2_seed42\\n-rw-r--r--   1 root root    3219 May 16 04:03 selection_f1_4b_results.json\\n-rw-r--r--   1 root root     807 May 20 17:06 sj_8b_qwen3_ft_progress.log\\n-rw-r--r--   1 root root    7000 May 20 17:06 sj_8b_qwen3_ft_results.json\\ndrwxr-xr-x   2 root root    4096 May 18 14:53 statistical_hardening\\ndrwxr-xr-x   2 root root      34 May 19 15:07 supervised_verifier_upgrade\\n-rw-r--r--   1 root root    4738 May 19 15:14 supervised_verifier_upgrade.log\\n-rw-r--r--   1 root root     359 May 19 06:55 supplement_degen_results.json\\n-rw-r--r--   1 root root    3327 May 18 17:31 task1_within_rho.py\\n-rw-r--r--   1 root root    3710 May 18 17:31 task2_dals_cross_model.py\\n-rw-r--r--   1 root root    2184 May 18 17:31 task3_llama_n16_check.py\\ndrwxr-xr-x   2 root root    4096 May 18 18:45 token_lp_aggregator\\n-rw-r--r--   1 root root    5056 May 18 18:45 token_lp_aggregator_fewnerd.log\\n-rw-r--r--   1 root root       0 May 18 18:39 token_lp_aggregator_scierc.log\\n-rw-r--r--   1 root root    5074 May 18 18:44 token_lp_aggregator_scierc_3ep.log\\n-rw-r--r--   1 root root    5077 May 18 18:42 token_lp_aggregator_scierc_v2.log\\ndrwxr-xr-x   2 root root     111 May 21 10:24 unified_degeneracy_audit\\ndrwxr-xr-x   2 root root      44 May 19 02:43 unified_metrics_regression\\ndrwxr-xr-x   2 root root      76 May 19 05:30 unified_oracle_audit\\n-rw-r--r--   1 root root    1314 May 18 12:42 unified_tab_fewnerd_maxlp.json\\n-rw-r--r--   1 root root     807 May 20 17:02 vc_8b_qwen3_ft_progress.log\\n-rw-r--r--   1 root root    7810 May 20 17:02 vc_8b_qwen3_ft_results.json\\n-rw-r--r--   1 root root    8953 May 16 12:56 vc_quartile_analysis.json\\n-rw-r--r--   1 root root    1241 May 18 17:31 within_instance_rho_table.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.94}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 19_

<details><summary>Logged reasoning block</summary>

```text
The output is truncated. Let me look at the registry data differently and also check specific experiment directories on the server. I need to find:

1. The experiment output directories that were used to build the α_crit table
2. Whether they used greedy_f1 (micro-F1, correct) or greedy_macro_f1 (incorrect)

From the table:
- FewNERD: seeds 123, 456, 789
- CoNLL: seeds 123, 456
- SciERC: seeds 456, 789

Let me check the server for the specific experiment directories and their report.json files. 

I'm also looking for MF4v2 experiments and scanning through the available directories. I can see some CoNLL and SciERC MF4 variants with different seeds, plus some MVP pilot runs, but I still need to locate the FewNERD T=1.0 experiments to verify which metrics were actually used in the table.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "6ce56834-af96-44a4-a01b-70eb6926dc5e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EuCyrojtm47Pzy9RjaoWeh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5369,
      "cache_read_input_tokens": 28724,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5369
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

_source line 20_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01MWtKDDVZE8V2qrVxSa7aRd`</summary>

```json
{
  "server": "autodl-5090",
  "command": "ls -d /root/autodl-tmp/struct_self_consist_ie/output/fewnerd* /root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot* /root/autodl-tmp/struct_self_consist_ie/output/conll* /root/autodl-tmp/struct_self_consist_ie/output/scierc* 2>/dev/null",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "333bff17-f7c9-4045-b2c1-0602daec9e78",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EuCyrojtm47Pzy9RjaoWeh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5369,
      "cache_read_input_tokens": 28724,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5369
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

_source line 21 · 2026-05-21T09:27:35.723Z_

<details><summary>↩ Tool result · `toolu_01MWtKDDVZE8V2qrVxSa7aRd`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "efc4b7ef-4c11-4b9b-a42d-1e975a4a7ef8",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '>' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 22_

<details open><summary>🔧 Tool call — Bash · `toolu_01E6197HoKCgMNeWrhoyXQNg`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/6986ae13-ffc9-44c1-9a46-461b58b60630/tool-results/mcp-agent-ml-research-read_registry-1779355628042.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\n# Check structure\nif isinstance(result, list):\n    print(f'Registry has {len(result)} experiments')\n    if len(result) > 0:\n        print(f'First entry type: {type(result[0])}')\n        if isinstance(result[0], dict):\n            print(f'Keys: {list(result[0].keys())[:10]}')\n        elif isinstance(result[0], str):\n            print(f'String entries - trying as dict keys')\n            # Maybe it's a dict\nelif isinstance(result, dict):\n    print(f'Registry is a dict with {len(result)} entries')\n    for k in list(result.keys())[:3]:\n        print(f'  key sample: {k}')\n        v = result[k]\n        if isinstance(v, dict):\n            print(f'  value keys: {list(v.keys())[:10]}')\n\" 2>&1",
  "description": "Check registry data structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "5bb4edd0-e6b2-47e9-bf4e-e4d640cdfd70",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EuCyrojtm47Pzy9RjaoWeh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5369,
      "cache_read_input_tokens": 28724,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5369
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

_source line 23 · 2026-05-21T09:27:42.379Z_

<details><summary>↩ Tool result · `toolu_01E6197HoKCgMNeWrhoyXQNg`</summary>

```text
Registry is a dict with 4 entries
  key sample: success
  key sample: data
  value keys: ['experiments', 'count', 'total', 'baseline']
  key sample: error
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "6dde9381-a249-49af-a064-d027314072e0",
  "tool_use_result": {
    "stdout": "Registry is a dict with 4 entries\n  key sample: success\n  key sample: data\n  value keys: ['experiments', 'count', 'total', 'baseline']\n  key sample: error",
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

_source line 24_

<details open><summary>🔧 Tool call — Bash · `toolu_0131kHZQXyvQEjEaE9bSZDS3`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/6986ae13-ffc9-44c1-9a46-461b58b60630/tool-results/mcp-agent-ml-research-read_registry-1779355628042.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\nprint(f'Total experiments: {len(exps)}')\n\n# Find alpha_crit / entity construction / T=1.0 related\nkeywords = ['alpha', 'crit', 'entity_construct', 'fewnerd', 'conll', 'scierc', 'mf4', 'pilot', 'greedy']\nfor exp in exps:\n    exp_id = exp.get('exp_id', '')\n    desc = str(exp.get('description', ''))\n    tags = exp.get('tags', []) or []\n    config = exp.get('config', {}) or {}\n    combined = (exp_id + ' ' + desc + ' ' + ' '.join(tags) + ' ' + str(config)).lower()\n    if any(k in combined for k in keywords):\n        metrics = exp.get('metrics', {}) or {}\n        relevant_m = {k:v for k,v in metrics.items() if any(x in k.lower() for x in ['greedy', 'f1', 'mv', 'alpha', 'degen', 'macro'])}\n        print(f'=== {exp_id} ===')\n        print(f'  status: {exp.get(\\\"status\\\")}')\n        print(f'  desc: {desc[:150]}')\n        print(f'  tags: {tags}')\n        seed = config.get('seed', config.get('seeds', 'N/A'))\n        dataset = config.get('dataset', 'N/A')\n        output_dir = config.get('output_dir', exp.get('output_dir', 'N/A'))\n        print(f'  seed={seed}, dataset={dataset}')\n        print(f'  output_dir: {output_dir}')\n        if relevant_m:\n            print(f'  metrics: {relevant_m}')\n        print()\n\" 2>&1 | head -300",
  "description": "Extract relevant experiments from registry",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "44f27b23-48b5-408e-b4b0-ef1cb3622140",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXCgM8KjPVQrYQVGXiQi9o",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1084,
      "cache_read_input_tokens": 34093,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1084
      },
      "output_tokens": 69,
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

_source line 25 · 2026-05-21T09:27:53.227Z_

<details><summary>↩ Tool result · `toolu_0131kHZQXyvQEjEaE9bSZDS3`</summary>

```text
Traceback (most recent call last):
  File "&lt;string>", line 11, in &lt;module>
    exp_id = exp.get('exp_id', '')
             ^^^^^^^
AttributeError: 'str' object has no attribute 'get'
Total experiments: 272
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "cd278015-a966-40dc-b5e0-e44d29783a69",
  "tool_use_result": {
    "stdout": "Traceback (most recent call last):\n  File \"&lt;string>\", line 11, in &lt;module>\n    exp_id = exp.get('exp_id', '')\n             ^^^^^^^\nAttributeError: 'str' object has no attribute 'get'\nTotal experiments: 272",
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

_source line 26_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01HzDz41vCxg8dEjfvYPT3M3`</summary>

```json
{
  "server": "autodl-5090",
  "command": "ls -d /root/autodl-tmp/struct_self_consist_ie/output/fewnerd*",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "5c2e6450-f677-4478-b122-c570c2e2a270",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXCgM8KjPVQrYQVGXiQi9o",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1084,
      "cache_read_input_tokens": 34093,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1084
      },
      "output_tokens": 69,
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

_source line 27 · 2026-05-21T09:27:54.002Z_

<details><summary>↩ Tool result · `toolu_01HzDz41vCxg8dEjfvYPT3M3`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_3seed_construction_bootstrap.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_dals_multiseed_results.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed123\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed42\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed456\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed123\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed42\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed456\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_multiseed_unified_v2.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.37}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "e08e51f7-4c32-462f-9caf-2a8d63e17227",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_3seed_construction_bootstrap.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_dals_multiseed_results.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed123\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed42\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed456\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed123\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed42\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed456\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_multiseed_unified_v2.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.37}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_3seed_construction_bootstrap.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_dals_multiseed_results.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed123\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed42\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed456\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed123\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed42\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed456\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_multiseed_unified_v2.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.37}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 28_

<details><summary>Logged reasoning block</summary>

```text
The experiments list contains strings, not dicts. Let me check the structure more carefully. Also, I see the FewNERD directories:
- fewnerd_mf4_seed123, fewnerd_mf4_seed42, fewnerd_mf4_seed456
- fewnerd_mf4v2_seed123, fewnerd_mf4v2_seed42, fewnerd_mf4v2_seed456
- fewnerd_seed789_merged

Let me check the report.json files in these directories. 

Now I need to fix the registry parsing issue.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "a49bedd3-a94b-4b51-8b43-9c13900f3859",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019bLfAV8UjNkyK9A8bAuQtn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1416,
      "cache_read_input_tokens": 35177,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1416
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

_source line 29_

<details open><summary>🔧 Tool call — Bash · `toolu_01SnHP2uRzidwxm4CmiEdmxW`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/6986ae13-ffc9-44c1-9a46-461b58b60630/tool-results/mcp-agent-ml-research-read_registry-1779355628042.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n# Check what type each element is\nprint(f'Type of first exp: {type(exps[0])}')\nif isinstance(exps[0], str):\n    # Maybe it's a list of exp_id strings\n    print('Exp IDs:')\n    for e in exps[:5]:\n        print(f'  {e}')\nelif isinstance(exps[0], list):\n    print(f'First exp (list): {exps[0][:5]}')\nelse:\n    print(f'First exp: {str(exps[0])[:300]}')\n\" 2>&1",
  "description": "Check experiment data structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "7c89df42-fbb3-42d0-8a0c-badd53701902",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019bLfAV8UjNkyK9A8bAuQtn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1416,
      "cache_read_input_tokens": 35177,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1416
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

_source line 30 · 2026-05-21T09:28:01.976Z_

<details><summary>↩ Tool result · reported error · `toolu_01SnHP2uRzidwxm4CmiEdmxW`</summary>

```text
Exit code 1
Traceback (most recent call last):
  File "&lt;string>", line 7, in &lt;module>
    print(f'Type of first exp: {type(exps[0])}')
                                     ~~~~^^^
KeyError: 0
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "4974a642-9be3-48bb-9839-321f7a389bb8",
  "tool_use_result": "Error: Exit code 1\nTraceback (most recent call last):\n  File \"&lt;string>\", line 7, in &lt;module>\n    print(f'Type of first exp: {type(exps[0])}')\n                                     ~~~~^^^\nKeyError: 0"
}
```

</details>

---


### Tool call

_source line 31_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01T6SpUNgyve625kFityZX9X`</summary>

```json
{
  "server": "autodl-5090",
  "command": "ls -d /root/autodl-tmp/struct_self_consist_ie/output/conll* /root/autodl-tmp/struct_self_consist_ie/output/scierc*",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "3f1bfe19-4c36-49b4-aded-42e132da5fd0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019bLfAV8UjNkyK9A8bAuQtn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1416,
      "cache_read_input_tokens": 35177,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1416
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

_source line 32 · 2026-05-21T09:28:02.752Z_

<details><summary>↩ Tool result · reported error · `toolu_01T6SpUNgyve625kFityZX9X`</summary>

```text
&lt;tool_use_error>Cancelled: parallel tool call Bash(cat /home/ubuntu/.claude-account-5/proje…) errored&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "098e6161-610b-4c81-aa4a-01b6e73065b7",
  "tool_use_result": "Cancelled: parallel tool call Bash(cat /home/ubuntu/.claude-account-5/proje…) errored"
}
```

</details>

---


### Tool call

_source line 33_

<details open><summary>🔧 Tool call — Bash · `toolu_01RXL3tR5NCuQhKV9WLdRFNJ`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/6986ae13-ffc9-44c1-9a46-461b58b60630/tool-results/mcp-agent-ml-research-read_registry-1779355628042.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\nprint(f'Type: {type(exps)}')\nif isinstance(exps, dict):\n    keys = list(exps.keys())[:5]\n    print(f'Dict keys sample: {keys}')\n    for k in keys:\n        v = exps[k]\n        print(f'  {k}: type={type(v)}, preview={str(v)[:200]}')\n\" 2>&1",
  "description": "Inspect experiments dict structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "40e2ad67-781a-4200-867e-f27849f02457",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HxGe3DJXUbLdNGWrXCCfAV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 809,
      "cache_read_input_tokens": 36593,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 809
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

_source line 34 · 2026-05-21T09:28:07.641Z_

<details><summary>↩ Tool result · `toolu_01RXL3tR5NCuQhKV9WLdRFNJ`</summary>

```text
Type: &lt;class 'dict'>
Dict keys sample: ['exp_conll_mf4_v2_s456', 'exp_conll_mf4_v2_s123', 'exp_frontier_sc_deepseek', 'exp_e2_pretrained_scierc', 'exp_conll_n16_s456_v2']
  exp_conll_mf4_v2_s456: type=&lt;class 'dict'>, preview={'status': 'DONE', 'retry_count': 0, 'created_at': '2026-05-21T05:34:10.294Z', 'updated_at': '2026-05-21T09:11:29.209Z', 'hypothesis': 'MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=456 using run_mvp_pilo
  exp_conll_mf4_v2_s123: type=&lt;class 'dict'>, preview={'status': 'DONE', 'retry_count': 0, 'created_at': '2026-05-21T05:34:09.147Z', 'updated_at': '2026-05-21T09:11:26.284Z', 'hypothesis': 'MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=123 using run_mvp_pilo
  exp_frontier_sc_deepseek: type=&lt;class 'dict'>, preview={'status': 'DONE', 'retry_count': 0, 'created_at': '2026-05-21T06:50:26.022Z', 'updated_at': '2026-05-21T09:10:40.589Z', 'hypothesis': 'Frontier model DeepSeek Chat on FewNERD SC (200 inst, N=8, T=1.0
  exp_e2_pretrained_scierc: type=&lt;class 'dict'>, preview={'status': 'DONE', 'retry_count': 0, 'created_at': '2026-05-21T07:18:21.189Z', 'updated_at': '2026-05-21T09:10:13.722Z', 'spec': {'command': 'bash -c "source /root/miniconda3/etc/profile.d/conda.sh &&
  exp_conll_n16_s456_v2: type=&lt;class 'dict'>, preview={'status': 'DONE', 'retry_count': 0, 'created_at': '2026-05-21T05:05:07.022Z', 'updated_at': '2026-05-21T09:10:12.516Z', 'hypothesis': 'CoNLL N=16 (seed=456, v2): retry after previous failure on 5090.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "bd1b0302-6253-45a0-a397-50e8e8ea4bc6",
  "tool_use_result": {
    "stdout": "Type: &lt;class 'dict'>\nDict keys sample: ['exp_conll_mf4_v2_s456', 'exp_conll_mf4_v2_s123', 'exp_frontier_sc_deepseek', 'exp_e2_pretrained_scierc', 'exp_conll_n16_s456_v2']\n  exp_conll_mf4_v2_s456: type=&lt;class 'dict'>, preview={'status': 'DONE', 'retry_count': 0, 'created_at': '2026-05-21T05:34:10.294Z', 'updated_at': '2026-05-21T09:11:29.209Z', 'hypothesis': 'MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=456 using run_mvp_pilo\n  exp_conll_mf4_v2_s123: type=&lt;class 'dict'>, preview={'status': 'DONE', 'retry_count': 0, 'created_at': '2026-05-21T05:34:09.147Z', 'updated_at': '2026-05-21T09:11:26.284Z', 'hypothesis': 'MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=123 using run_mvp_pilo\n  exp_frontier_sc_deepseek: type=&lt;class 'dict'>, preview={'status': 'DONE', 'retry_count': 0, 'created_at': '2026-05-21T06:50:26.022Z', 'updated_at': '2026-05-21T09:10:40.589Z', 'hypothesis': 'Frontier model DeepSeek Chat on FewNERD SC (200 inst, N=8, T=1.0\n  exp_e2_pretrained_scierc: type=&lt;class 'dict'>, preview={'status': 'DONE', 'retry_count': 0, 'created_at': '2026-05-21T07:18:21.189Z', 'updated_at': '2026-05-21T09:10:13.722Z', 'spec': {'command': 'bash -c \"source /root/miniconda3/etc/profile.d/conda.sh &&\n  exp_conll_n16_s456_v2: type=&lt;class 'dict'>, preview={'status': 'DONE', 'retry_count': 0, 'created_at': '2026-05-21T05:05:07.022Z', 'updated_at': '2026-05-21T09:10:12.516Z', 'hypothesis': 'CoNLL N=16 (seed=456, v2): retry after previous failure on 5090.",
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

_source line 35_

<details><summary>Logged reasoning block</summary>

```text
Now I understand the structure. Let me search for experiments related to the α_crit table. I need to find:
1. FewNERD experiments with seeds 123, 456, 789 at T=1.0
2. CoNLL experiments with seeds 123, 456 at T=1.0
3. SciERC experiments with seeds 456, 789 at T=1.0
4. MF4v2 experiments

Let me query for these specifically and also check the server report.json files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "021fcb9e-c847-4816-ab15-cb0e313d19bb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GAv8MKQAPW2XVDsfNzZ1Uw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1026,
      "cache_read_input_tokens": 37402,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1026
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

_source line 36_

<details open><summary>🔧 Tool call — Bash · `toolu_013UKutd8eYmREMgyrfVnYFf`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/6986ae13-ffc9-44c1-9a46-461b58b60630/tool-results/mcp-agent-ml-research-read_registry-1779355628042.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\nkeywords = ['fewnerd', 'conll', 'scierc', 'mf4', 'alpha', 'pilot', 'entity_construct']\nfor exp_id, exp in exps.items():\n    combined = (exp_id + ' ' + str(exp.get('hypothesis','')) + ' ' + str(exp.get('tags',''))).lower()\n    if any(k in combined for k in keywords):\n        metrics = exp.get('metrics', {}) or {}\n        config = exp.get('config', {}) or {}\n        spec = exp.get('spec', {}) or {}\n        relevant_m = {k:round(v,4) if isinstance(v,float) else v for k,v in metrics.items() if any(x in k.lower() for x in ['greedy', 'f1', 'mv', 'alpha', 'degen', 'macro', 'micro'])}\n        print(f'=== {exp_id} === [{exp.get(\\\"status\\\")}]')\n        print(f'  hyp: {str(exp.get(\\\"hypothesis\\\",\\\"\\\"))[:180]}')\n        seed = config.get('seed', spec.get('seed', 'N/A'))\n        dataset = config.get('dataset', spec.get('dataset', 'N/A'))\n        output_dir = config.get('output_dir', exp.get('output_dir', spec.get('output_dir', '')))\n        print(f'  seed={seed}, dataset={dataset}')\n        if output_dir:\n            print(f'  output_dir: {output_dir}')\n        if relevant_m:\n            print(f'  metrics: {relevant_m}')\n        conclusion = exp.get('conclusion', '')\n        if conclusion:\n            print(f'  conclusion: {str(conclusion)[:200]}')\n        print()\n\" 2>&1 | head -500",
  "description": "Extract relevant experiments with full details",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "3a518d0a-b7fa-4c9b-92de-c222a5ef978e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GAv8MKQAPW2XVDsfNzZ1Uw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1026,
      "cache_read_input_tokens": 37402,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1026
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

_source line 37 · 2026-05-21T09:28:19.606Z_

<details><summary>↩ Tool result · `toolu_013UKutd8eYmREMgyrfVnYFf`</summary>

```text
=== exp_conll_mf4_v2_s456 === [DONE]
  hyp: MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). 3-seed set with exp_conll_t10_s42.
  seed=456, dataset=N/A
  metrics: {'greedy_f1': 0.907, 'oracle_f1': 0.9426, 'sample_f1_mean': 0.8737, 'sample_f1_pct_zero': 7.08}
  conclusion: success

=== exp_conll_mf4_v2_s123 === [DONE]
  hyp: MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). 3-seed set with exp_conll_t10_s42.
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.9083, 'oracle_f1': 0.9527, 'sample_f1_mean': 0.8744, 'sample_f1_pct_zero': 7.05}
  conclusion: success

=== exp_frontier_sc_deepseek === [DONE]
  hyp: Frontier model DeepSeek Chat on FewNERD SC (200 inst, N=8, T=1.0): 4-family cross-validation of correlation-selection gap universality.
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.3992, 'mv_f1': 0.4243, 'oracle_f1': 0.714, 'degeneracy_rate': 0.055, 'mv_gain_over_greedy': 0.0251}
  conclusion: success

=== exp_e2_pretrained_scierc === [DONE]
  hyp: E2 pre-trained baseline: Qwen2.5-7B-Instruct (unfinetuned) on SciERC SC pipeline N=8 T=1.0. Third dataset for E2 baseline, validates whether correlation-selection gap exists withou
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.2418, 'oracle_f1': 0.3888, 'sample_f1_mean': 0.2272, 'sample_f1_pct_zero': 46.29}
  conclusion: negative

=== exp_conll_n16_s456_v2 === [DONE]
  hyp: CoNLL N=16 (seed=456, v2): retry after previous failure on 5090. Third seed for 3-seed statistical power on CoNLL-2003 N=16.
  seed=456, dataset=N/A
  metrics: {'greedy_f1': 0.9076, 'oracle_f1': 0.955, 'sample_f1_mean': 0.8736, 'sample_f1_pct_zero': 7.03}
  conclusion: success

=== exp_conll_n16_s123_v2 === [DONE]
  hyp: CoNLL N=16 (seed=123, v2): retry after previous failure on 5090 (damaged checkpoint). Extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003.
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.9071, 'oracle_f1': 0.9625, 'sample_f1_mean': 0.8676, 'sample_f1_pct_zero': 7.52}
  conclusion: success

=== exp_scierc_mf4_v2_s42 === [PREPARING]
  hyp: 
  seed=N/A, dataset=N/A

=== exp_frontier_sc_claude_sonnet4 === [DONE]
  hyp: Frontier model Claude Sonnet 4 on FewNERD SC (200 instances, N=8, T=1.0): if correlation-selection gap persists across model families (GPT + Claude + Gemini + DeepSeek), the findin
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.6068, 'mv_f1': 0.6226, 'oracle_f1': 0.6544, 'degeneracy_rate': 0.74}
  conclusion: success

=== exp_e2_pretrained_conll === [DONE]
  hyp: E2 pre-trained baseline: Qwen2.5-7B-Instruct (unfinetuned) on CoNLL SC pipeline N=8 T=1.0. Cross-dataset validation of pre-trained baseline. Together with FewNERD baseline, shows w
  seed=42, dataset=N/A
  conclusion: success

=== exp_frontier_sc_gpt55_fewnerd_v2 === [DONE]
  hyp: Frontier model GPT-5.5 on FewNERD SC (200 instances, N=8, T=1.0): if correlation-selection gap persists in frontier models, the finding is fundamental and not a model capability li
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.6382, 'mv_f1': 0.6521, 'oracle_f1': 0.7203, 'degeneracy_rate': 0.5}
  conclusion: success

=== exp_fewnerd_mf4_v2_s456 === [PREPARING]
  hyp: MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). Third seed completing 3-seed set for statistical power.
  seed=N/A, dataset=N/A

=== exp_fewnerd_n16_s123 === [DONE]
  hyp: FewNERD N=16 (seed=123): extending N-scaling curve to N=16 for Qwen3-8B-FT. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) sc
  seed=N/A, dataset=N/A
  metrics: {'greedy_f1': 0.7888, 'oracle_f1': 0.9147}
  conclusion: success

=== exp_fewnerd_n16_s42 === [DONE]
  hyp: FewNERD N=16 (seed=42): extending N-scaling curve to N=16 for Qwen3-8B-FT. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) sca
  seed=N/A, dataset=N/A
  metrics: {'greedy_f1': 0.7886, 'oracle_f1': 0.9059}
  conclusion: success

=== exp_fewnerd_t12_s456 === [DONE]
  hyp: FewNERD temperature ablation (T=1.2, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT.
  seed=456, dataset=N/A
  metrics: {'greedy_f1': 0.7885, 'oracle_f1': 0.8775, 'degeneracy_rate': None}
  conclusion: success

=== exp_fewnerd_mf4v2_s42 === [PREPARING]
  hyp: 
  seed=N/A, dataset=N/A

=== exp_fewnerd_mf4v2_s123 === [PREPARING]
  hyp: 
  seed=N/A, dataset=N/A

=== exp_14b_inference_fewnerd === [DONE]
  hyp: 14B Qwen2.5 inference on FewNERD (N∈{1,2,4,8}): primary dataset should show oracle scaling law F1(N)=a-b*N^(-c) consistent at 14B scale, filling the scaling curve between 7B and 32
  seed=42, dataset=N/A
  conclusion: success

=== exp_fewnerd_mf4_v2_s42 === [DONE]
  hyp: MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=42 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1. 3-seed statistical power.
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.7883, 'oracle_f1': 0.8783, 'sample_f1_mean': 0.6123, 'sample_f1_std': 0.3913, 'sample_f1_pct_zero': 23.09, 'n_greedy_f1_zero_filtered': 3883}
  conclusion: negative

=== exp_fewnerd_mf4_v2_s123 === [DONE]
  hyp: MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1. 3-seed statistical power.
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.7883, 'oracle_f1': 0.8891, 'sample_f1_mean': 0.6364, 'sample_f1_std': 0.3819, 'sample_f1_pct_zero': 20.49, 'n_greedy_f1_zero_filtered': 3880}
  conclusion: success

=== exp_fewnerd_n16_s456_v2 === [RUNNING]
  hyp: FewNERD N=16 (seed=456, v2 rerun): data lost in previous run. Extending N-scaling curve to N=16 for Qwen3-8B-FT, critical for F1(N)=a-b*N^(-c) scaling law. Third seed for 3-seed st
  seed=456, dataset=N/A

=== exp_fewnerd_7b_n16_s42 === [DONE]
  hyp: FewNERD N=16 with Qwen2.5-7B: extending N-scaling curve to N=16 for 7B model. At N=8 the 7B model shows diminishing oracle gains; N=16 tests whether the plateau continues or breaks
  seed=42, dataset=N/A
  conclusion: failed

=== exp_fewnerd_n16_s456 === [DONE]
  hyp: FewNERD N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) sc
  seed=456, dataset=N/A
  conclusion: failed

=== exp_e2_pretrained_fewnerd === [RUNNING]
  hyp: E2 pre-trained baseline: Qwen2.5-7B-Instruct (unfinetuned) on FewNERD SC pipeline N=8 T=1.0. Tests whether correlation-selection gap exists without task-specific fine-tuning. If ga
  seed=42, dataset=N/A

=== exp_conll_mf4_s456 === [DONE]
  hyp: MF4 pipeline fix: CoNLL N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). Extends exp_conll_t10_s42 to 3-seed set for statistical power.
  seed=456, dataset=N/A
  conclusion: killed

=== exp_frontier_sc_gemini25pro === [RUNNING]
  hyp: Frontier model Gemini 2.5 Pro on FewNERD SC (200 inst, N=8, T=1.0): 4-family cross-validation. If correlation-selection gap persists across GPT + Claude + Gemini + DeepSeek, the fi
  seed=42, dataset=N/A

=== exp_conll_mf4_s123 === [DONE]
  hyp: MF4 pipeline fix: CoNLL N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). Extends exp_conll_t10_s42 to 3-seed set for statistical power.
  seed=123, dataset=N/A
  conclusion: killed

=== exp_fewnerd_t05_s456 === [DONE]
  hyp: FewNERD temperature ablation (T=0.5, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT.
  seed=456, dataset=N/A
  conclusion: success

=== exp_fewnerd_mf4_s456 === [QUEUED]
  hyp: MF4 pipeline fix: FewNERD N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1 metric. Required for 3-seed stati
  seed=N/A, dataset=N/A
  conclusion: killed

=== exp_fewnerd_mf4_s123 === [QUEUED]
  hyp: MF4 pipeline fix: FewNERD N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1 metric. Required for 3-seed stati
  seed=N/A, dataset=N/A
  conclusion: killed

=== exp_fewnerd_mf4_s42 === [QUEUED]
  hyp: MF4 pipeline fix: FewNERD N=8 T=1.0 seed=42 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1 metric. Required for 3-seed statis
  seed=N/A, dataset=N/A
  conclusion: killed

=== exp_14b_inference_conll === [DONE]
  hyp: 14B Qwen2.5 inference on CoNLL (N∈{1,2,4,8}): filling scale curve between 8B (greedy F1=0.907) and 32B. Tests whether 14B shows intermediate behavior in SC diagnostic metrics.
  seed=42, dataset=N/A
  conclusion: killed

=== exp_conll_n16_s456 === [DONE]
  hyp: CoNLL N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a
  seed=N/A, dataset=N/A
  conclusion: failed

=== exp_conll_n16_s123 === [DONE]
  hyp: CoNLL N=16 (seed=123): extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a
  seed=N/A, dataset=N/A
  conclusion: failed

=== exp_scierc_n16_s456 === [DONE]
  hyp: SciERC N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT on SciERC. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*
  seed=456, dataset=N/A
  conclusion: success

=== exp_scierc_n16_s123 === [DONE]
  hyp: SciERC N=16 (seed=123): extending N-scaling curve to N=16 for Qwen3-8B-FT on SciERC. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*
  seed=123, dataset=N/A
  conclusion: success

=== exp_scierc_t12_s456 === [DONE]
  hyp: SciERC temperature ablation (T=1.2, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.
  seed=N/A, dataset=N/A
  metrics: {'greedy_f1': 0.663, 'oracle_f1': 0.782, 'degeneracy_pct': 14.1}
  conclusion: success

=== exp_conll_n16_s42 === [DONE]
  hyp: CoNLL N=16 ablation (T=1.0, seed=42): test whether doubling sample count from N=8 to N=16 improves SC diagnostic correlation and oracle F1 on CoNLL-2003. Qwen3-8B-FT.
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.908, 'oracle_f1': 0.959, 'degeneracy_pct': 7.8}
  conclusion: success

=== exp_scierc_t08_s123 === [DONE]
  hyp: SciERC temperature ablation (T=0.8, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.662, 'oracle_f1': 0.773, 'degeneracy_pct': 11.2}
  conclusion: success

=== exp_scierc_t08_s456 === [DONE]
  hyp: SciERC temperature ablation (T=0.8, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.
  seed=N/A, dataset=N/A
  metrics: {'greedy_f1': 0.664, 'oracle_f1': 0.769, 'degeneracy_pct': 11.9}
  conclusion: success

=== exp_scierc_t05_s456 === [DONE]
  hyp: SciERC temperature ablation (T=0.5, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.
  seed=N/A, dataset=N/A
  metrics: {'greedy_f1': 0.663, 'oracle_f1': 0.746, 'degeneracy_pct': 10.3}
  conclusion: success

=== exp_scierc_t12_s123 === [DONE]
  hyp: SciERC temperature ablation (T=1.2, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.664, 'oracle_f1': 0.788, 'degeneracy_pct': 13.9}
  conclusion: success

=== exp_scierc_t05_s123 === [DONE]
  hyp: SciERC temperature ablation (T=0.5, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.665, 'oracle_f1': 0.743, 'degeneracy_pct': 10}
  conclusion: success

=== exp_fewnerd_t08_s456 === [DONE]
  hyp: FewNERD T-ablation seed=456 (T=0.8): third seed for T=0.8 sweet-spot, providing 3-seed statistical power for the key operating point. With seeds 42/123/456, can compute confidence 
  seed=456, dataset=N/A
  metrics: {'greedy_f1': 0.788, 'oracle_f1': 0.877, 'degeneracy_pct': 16.3}
  conclusion: success

=== exp_fewnerd_t12_s123 === [DONE]
  hyp: FewNERD T-ablation seed=123 replication (T=1.2): second seed for statistical power on T=1.2 negative result (over-diversification, 28.2% degeneracy, lowest rho_SJ=0.136 in seed=42)
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.789, 'oracle_f1': 0.887, 'degeneracy_pct': 24.7}
  conclusion: negative

=== exp_fewnerd_t08_s123 === [DONE]
  hyp: FewNERD T-ablation seed=123 replication (T=0.8): second seed for statistical power on T=0.8 sweet-spot hypothesis (best rho_advantage=0.102 SJ over Fleiss, balanced oracle headroom
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.789, 'oracle_f1': 0.884, 'degeneracy_pct': 16.7}
  conclusion: success

=== exp_fewnerd_t05_s123 === [DONE]
  hyp: FewNERD T-ablation seed=123 replication (T=0.5): second seed for statistical power on T=0.5 findings (highest rho_SJ=0.267, lowest oracle headroom=6.85% in seed=42). Confirms wheth
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.789, 'oracle_f1': 0.864, 'degeneracy_pct': 13.5}
  conclusion: success

=== exp_32b_inference_fewnerd === [DONE]
  hyp: 32B fine-tuned model (Qwen2.5-32B-Instruct QLoRA, best checkpoint-32000) FewNERD inference with N=8 SC sampling. Scaling from 8B→32B should improve per-sample quality and strengthe
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.8, 'oracle_f1': 0.879}
  conclusion: success

=== exp_hidden_state_probe_fulldata === [DONE]
  hyp: Hidden states of fine-tuned Qwen3-8B encode entity quality information that a linear probe can detect with AUROC significantly above chance, even under GroupKFold (no instance leak
  seed=42,123,456, dataset=N/A
  conclusion: success

=== exp_conll_t10_s42 === [DONE]
  hyp: CoNLL T=1.0 baseline (seed=42): fills the gap in the temperature ablation matrix (T=0.5/0.8/1.2 already complete with 3 seeds). T=1.0 is the default sampling temperature and should
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.9077, 'oracle_f1': 0.9503, 'sample_f1_mean': 0.871, 'sample_f1_pct_zero': 7.53}
  conclusion: success

=== exp_scierc_probe === [DONE]
  hyp: SciERC hidden state probe: test if linear classifier on last-layer hidden states can predict entity quality (match vs non-match against gold). If AUROC ≈ 0.98 (consistent with FewN
  seed=42, dataset=N/A
  conclusion: success

=== exp_conll_t12_s456 === [DONE]
  hyp: CoNLL temperature ablation (T=1.2, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.
  seed=456, dataset=N/A
  metrics: {'greedy_f1': 0.9071, 'oracle_f1': 0.9452, 'rho_SJ_F1_full': 0.4553, 'rho_SJ_F1_conditional': 0.4259, 'degeneracy_rate_pct': 8.34}
  conclusion: success

=== exp_conll_t08_s456 === [DONE]
  hyp: CoNLL temperature ablation (T=0.8, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.
  seed=456, dataset=N/A
  metrics: {'greedy_f1': 0.9064, 'oracle_f1': 0.9407, 'rho_SJ_F1_full': 0.4877, 'rho_SJ_F1_conditional': 0.4756, 'degeneracy_rate_pct': 6.29}
  conclusion: success

=== exp_conll_t05_s456 === [DONE]
  hyp: CoNLL temperature ablation (T=0.5, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.
  seed=456, dataset=N/A
  metrics: {'greedy_f1': 0.9075, 'oracle_f1': 0.9338, 'rho_SJ_F1_full': 0.4549, 'rho_SJ_F1_conditional': 0.469, 'degeneracy_rate_pct': 5.62}
  conclusion: success

=== exp_fewnerd_t05_s42 === [DONE]
  hyp: FewNERD temperature ablation (T=0.5): test how lower temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwen3-8B-F
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.7884, 'oracle_f1': 0.8569, 'sample_f1_mean': 0.7154, 'degeneracy_rate': 0.146, 'rho_SJ_F1_full': 0.2667, 'rho_SJ_F1_conditional': 0.2988, 'rho_fleiss_F1_full': 0.2231, 'rho_fleiss_F1_conditional': 0.2338, 'rho_logprob_F1_full': 0.3558, 'rho_logprob_F1_conditional': 0.3025}
  conclusion: success

=== exp_fewnerd_t08_s42 === [DONE]
  hyp: FewNERD temperature ablation (T=0.8): test how moderate-low temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwe
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.7884, 'oracle_f1': 0.875, 'sample_f1_mean': 0.6622, 'degeneracy_rate': 0.1897, 'rho_SJ_F1_full': 0.2062, 'rho_SJ_F1_conditional': 0.2248, 'rho_fleiss_F1_full': 0.1038, 'rho_logprob_F1_full': 0.2323, 'rho_logprob_F1_conditional': 0.1984}
  conclusion: success

=== exp_fewnerd_t12_s42 === [DONE]
  hyp: FewNERD temperature ablation (T=1.2): test how higher temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwen3-8B-
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.7888, 'oracle_f1': 0.875, 'sample_f1_mean': 0.5524, 'degeneracy_rate': 0.2818, 'rho_SJ_F1_full': 0.136, 'rho_SJ_F1_conditional': 0.2125, 'rho_fleiss_F1_full': 0.0605, 'rho_logprob_F1_conditional': 0.1912}
  conclusion: negative

=== exp_conll_t12_s123 === [DONE]
  hyp: CoNLL temperature ablation (T=1.2, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.9072, 'oracle_f1': 0.955, 'sample_f1_mean': 0.8438, 'sample_f1_pct_zero': 9.1}
  conclusion: success

=== exp_conll_t08_s123 === [DONE]
  hyp: CoNLL temperature ablation (T=0.8, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.9068, 'oracle_f1': 0.9466, 'sample_f1_mean': 0.8897, 'sample_f1_pct_zero': 6.1}
  conclusion: success

=== exp_conll_t05_s123 === [DONE]
  hyp: CoNLL temperature ablation (T=0.5, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.
  seed=123, dataset=N/A
  metrics: {'greedy_f1': 0.9073, 'oracle_f1': 0.9351, 'sample_f1_mean': 0.901, 'sample_f1_pct_zero': 5.5}
  conclusion: success

=== exp_qwen25_32b_fewnerd === [DONE]
  hyp: Qwen2.5-32B-Instruct QLoRA fine-tuning on FewNERD: scaling model from 8B→32B should improve per-sample NER quality, enabling stronger SC diagnostic signals. LoRA r=32, alpha=64, ta
  seed=42, dataset=N/A
  output_dir: /root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-32b-fewnerd-qlora-s42
  metrics: {'lora_alpha': 64}
  conclusion: success

=== exp_conll_t_ablation_t12 === [DONE]
  hyp: CoNLL temperature ablation (T=1.2): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.9071, 'oracle_f1': 0.9514, 'degen_pct': 9.22, 'sample_f1_mean': 0.8452}
  conclusion: success

=== exp_conll_t_ablation_t08 === [DONE]
  hyp: CoNLL temperature ablation (T=0.8): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.9069, 'oracle_f1': 0.9464, 'degen_pct': 6.57, 'sample_f1_mean': 0.8854}
  conclusion: success

=== exp_conll_t_ablation_t05 === [DONE]
  hyp: CoNLL temperature ablation (T=0.5): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.9077, 'oracle_f1': 0.9372, 'degen_pct': 5.64, 'sample_f1_mean': 0.8993}
  conclusion: success

=== exp_conll_t05_s42 === [DONE]
  hyp: CoNLL T=0.5 temperature point: test low temperature on CoNLL2003 to extend cross-dataset T-ablation evidence beyond SciERC and FewNERD. N=8, Qwen3-8B-FT-CoNLL, seed=42. Complements
  seed=42, dataset=N/A
  metrics: {'greedy_f1': 0.9083, 'oracle_f1': 0.9376, 'degen_pct': 5.64, 'sample_f1_mean': 0.8994}
  conclusion: success

=== exp_spider_sc_pilot === [DONE]
  hyp: SC diagnostic cascade (degeneracy, agreement-correctness correlation, failure mode classification F1-F4) validated on NER structured generation will also manifest in SQL structured
  seed=42, dataset=N/A
  metrics: {'greedy_acc': 0.7653, 'mv_acc': 0.7704, 'mv_gain_pp': 0.51, 'degeneracy_rate': 0.8724, 'F1_degeneracy_rate': 0.872, 'nondegen_n': 25, 'nondegen_greedy_acc': 0.32, 'nondegen_mv_acc': 0.36, 'nondegen_oracle_acc': 0.64, 'nondegen_spearman_rho': 0.13}
  conclusion: success

=== exp_fewrel_re_sc === [DONE]
  hyp: SC consensus construction improves RE micro-F1 over greedy decoding on FewRel (16 relation types, Wikipedia domain), extending cross-task universality evidence beyond SciERC and Do
  seed=42, dataset=N/A
  metrics: {'greedy_micro_f1': 0.0751, 'construction_micro_f1': 0.0881, 'majority_vote_f1_mean': 0.0591, 'oracle_f1_mean': 0.1768, 'degeneracy_rate': 0.0586}
  conclusion: negative

=== exp_b_frontier_sc_fewnerd === [DONE]
  hyp: The correlation-selection gap in structured self-consistency (where agreement correlates with accuracy but majority voting fails to improve over greedy) persists even with frontier
  seed=42, dataset=N/A
  conclusion: failed

=== exp_docred_re_sc === [DONE]
  hyp: SC diagnostic cascade (degeneracy, correlation-selection gap, F1-F4 failure modes) generalizes from NER to document-level RE on DocRED, with Qwen2.5-7B-Instruct showing similar fai
  seed=42, dataset=N/A
  metrics: {'greedy_f1_mean': 0.0284, 'construction_f1_mean': 0.0338, 'majority_vote_f1_mean': 0.0263, 'oracle_f1_mean': 0.0999, 'greedy_micro_f1': 0.0297, 'construction_micro_f1': 0.0323, 'degeneracy_rate': 0.035, 'nondegen_construction_greedy_diff': 0.0055}
  conclusion: success

=== exp_b1_scd === [PENDING]
  hyp: Self-Consistency Distillation via theta2n construction pseudo-labels can teach Qwen3-8B-FT to internalize SC benefits: after iterative SCD (M0→M1→M2→M3), greedy F1 should approach 
  seed=N/A, dataset=N/A
  conclusion: killed

=== eval_scd_fewnerd_fallback === [PREPARING]
  hyp: 
  seed=N/A, dataset=N/A
  conclusion: killed

=== exp_b1_scd_fewnerd_curriculum_q === [DONE]
  hyp: Q variant SCD with curriculum ordering: use B2 entity verifier confidence to stratify pseudo-labels (conf>0.8→Round1, 0.5-0.8→Round2, conf<0.5→discard). Curriculum by verifier conf
  seed=43, dataset=N/A
  metrics: {'eval_greedy_f1': 0.7866, 'eval_greedy_precision': 0.7663, 'eval_greedy_recall': 0.808, 'eval_instance_avg_f1': 0.7809, 'baseline_greedy_f1': 0.748}
  conclusion: negative

=== exp_b1_scd_fewnerd_standard === [DONE]
  hyp: Standard Self-Consistency Distillation on FewNERD: fine-tune Qwen3-8B-FT with theta2n construction pseudo-labels (32,565 instances) mixed 1:1 with gold data. Greedy F1 after SCD sh
  seed=42, dataset=N/A
  conclusion: negative

=== exp_b1_scd_threshold_ablation === [DONE]
  hyp: Construction threshold sweep for SCD pseudo-label generation on FewNERD: θ∈{1/N, 2/N, 3/N, 0.5}. Higher θ = more conservative pseudo-labels (higher precision, lower recall). Optima
  seed=42, dataset=N/A
  conclusion: failed

=== exp_tlow_fewnerd_inference === [DONE]
  hyp: Lower temperature (T=0.5) sampling on FewNERD produces less diverse but higher-quality samples that, when combined with T=1.0 samples in heterogeneous-temperature selection, improv
  seed=42, dataset=N/A
  conclusion: success

=== exp_14b_inference_scierc === [DONE]
  hyp: 14B Qwen2.5 inference on SciERC (N∈{1,2,4,8,16}): correlation-selection gap pattern should be consistent at 14B scale with intermediate degeneracy rates between 7B and 32B.
  seed=N/A, dataset=N/A
  conclusion: killed

=== exp_qwen25_14b_fewnerd === [DONE]
  hyp: The correlation-selection gap pattern is consistent at 14B scale, filling the gap between 8B and 32B. Qwen2.5-14B QLoRA fine-tuned on FewNERD should show intermediate degeneracy ra
  seed=42, dataset=N/A
  conclusion: success

=== exp_b1_scd_conll_control === [DONE]
  hyp: Negative control: SCD on CoNLL where construction gain is negative (-0.4pp, high degeneracy 70%). If SCD learns from construction pseudo-labels, it should NOT improve greedy F1 on 
  seed=42, dataset=N/A
  metrics: {'pre_scd_greedy_f1': 0.9078, 'post_scd_greedy_f1': 0.9184}
  conclusion: negative

=== exp_b2_v2_multi_domain_joint === [PREPARING]
  hyp: Joint multi-domain training (CoNLL+SciERC+FewNERD LODO) improves entity verifier AUC and cross-domain construction F1 by exposing the model to diverse entity patterns. Tests whethe
  seed=N/A, dataset=N/A
  metrics: {'fold3_fewnerd_f1_delta': -0.008}
  conclusion: negative

=== exp_b2_entity_verifier === [PREPARING]
  hyp: An XGBoost/LightGBM entity-level verifier trained on agreement_count, VC, LP features can predict whether entity candidates are in gold annotations, enabling post-hoc filtering or 
  seed=N/A, dataset=N/A
  metrics: {'oof_path_a_f1_delta': 0.003, 'oof_path_b_f1_delta': -0.0157, 'oof_greedy_f1': 0.8216, 'oof_path_a_f1': 0.8246, 'oof_majority_vote_f1': 0.8048}
  conclusion: negative

=== exp_qwen25_7b_fewnerd === [DONE]
  hyp: Qwen2.5-7B QLoRA fine-tuned on FewNERD will produce structurally diverse samples enabling self-consistency-based entity extraction with meaningful LP-weighted consensus signals, co
  seed=42, dataset=N/A
  conclusion: success

=== exp_wnut17_qwen25_7b === [DONE]
  hyp: The correlation-selection gap extends to noisy social media NER (WNUT-17). Unlike formal-domain datasets (SciERC/CoNLL/FewNERD), WNUT-17 has higher surface-level noise which may af
  seed=42, dataset=N/A
  conclusion: negative

=== exp_llama_fewnerd_inference === [DONE]
  hyp: LLaMA-3.1-8B fine-tuned on FewNERD shows the same structured self-consistency phenomena (degeneracy, LP-F1 alignment, signal ranking) as Qwen models, providing cross-model generali
  seed=42,123,456, dataset=N/A
  conclusion: success

=== exp_entity_construction === [DONE]
  hyp: Entity-level majority vote construction is the correct self-consistency analogy for structured IE: instead of selecting the best instance-level output, assemble a better output fro
  seed=42, dataset=N/A
  conclusion: success

=== exp_llama_fewnerd_lora === [DONE]
  hyp: LLaMA-based model with LoRA fine-tuning on Few-NERD can provide a second model family (beyond Qwen) for cross-model generalization evidence of structured self-consistency phenomena
  seed=42, dataset=N/A
  conclusion: success

=== hidden_state_probe_conll_full === [DONE]
  hyp: 
  seed=N/A, dataset=N/A
  conclusion: killed

=== hidden_state_probe_conll_v2 === [DONE]
  hyp: 
  seed=N/A, dataset=N/A
  conclusion: killed

=== exp_031_fewnerd_t12 === [DONE]
  hyp: FewNERD T=1.2 temperature ablation: test if higher temperature reduces degeneracy on FewNERD as observed on SciERC
  seed=N/A, dataset=N/A
  conclusion: killed

=== exp_030_conll_t12 === [DONE]
  hyp: CoNLL T=1.2 temperature ablation: test if higher temperature reduces degeneracy on CoNLL as observed on SciERC
  seed=N/A, dataset=N/A
  conclusion: killed

=== mbr_pilot === [DONE]
  hyp: 
  seed=N/A, dataset=N/A
  conclusion: killed

=== dgs_pilot === [DONE]
  hyp: Degeneracy-Gated Selection (DGS) validates Two-Condition Theory: using degeneracy rate as gating mechanism to switch between greedy (degenerate) and LP selection (non-degenerate), 
  seed=N/A, dataset=N/A
  conclusion: killed

=== exp_fewnerd_s789_n8 === [DONE]
  hyp: FewNERD seed789 (4th seed) for statistical CI strengthening: 4-seed protocol provides tighter confidence intervals on LP selection gain and DGS effectiveness in low-degeneracy regi
  seed=789, dataset=N/A
  metrics: {'greedy_f1': 0.7478, 'oracle_f1': 0.8714, 'degen_rate': 0.1177, 'degen_rate_source': 'unified_metrics_constant_f1_gold_filtered', 'lp_sel_f1': 0.7614, 'dgs_f1': 0.7621, 'four_seed_mean_greedy': 0.7481}
  conclusion: success

=== exp_026_t12_seed456 === [DONE]
  hyp: Temperature ablation (T=1.2, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.
  seed=456, dataset=N/A
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "c5a48db7-a553-4a35-ae62-23c240c91b27",
  "tool_use_result": {
    "stdout": "=== exp_conll_mf4_v2_s456 === [DONE]\n  hyp: MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). 3-seed set with exp_conll_t10_s42.\n  seed=456, dataset=N/A\n  metrics: {'greedy_f1': 0.907, 'oracle_f1': 0.9426, 'sample_f1_mean': 0.8737, 'sample_f1_pct_zero': 7.08}\n  conclusion: success\n\n=== exp_conll_mf4_v2_s123 === [DONE]\n  hyp: MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). 3-seed set with exp_conll_t10_s42.\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.9083, 'oracle_f1': 0.9527, 'sample_f1_mean': 0.8744, 'sample_f1_pct_zero': 7.05}\n  conclusion: success\n\n=== exp_frontier_sc_deepseek === [DONE]\n  hyp: Frontier model DeepSeek Chat on FewNERD SC (200 inst, N=8, T=1.0): 4-family cross-validation of correlation-selection gap universality.\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.3992, 'mv_f1': 0.4243, 'oracle_f1': 0.714, 'degeneracy_rate': 0.055, 'mv_gain_over_greedy': 0.0251}\n  conclusion: success\n\n=== exp_e2_pretrained_scierc === [DONE]\n  hyp: E2 pre-trained baseline: Qwen2.5-7B-Instruct (unfinetuned) on SciERC SC pipeline N=8 T=1.0. Third dataset for E2 baseline, validates whether correlation-selection gap exists withou\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.2418, 'oracle_f1': 0.3888, 'sample_f1_mean': 0.2272, 'sample_f1_pct_zero': 46.29}\n  conclusion: negative\n\n=== exp_conll_n16_s456_v2 === [DONE]\n  hyp: CoNLL N=16 (seed=456, v2): retry after previous failure on 5090. Third seed for 3-seed statistical power on CoNLL-2003 N=16.\n  seed=456, dataset=N/A\n  metrics: {'greedy_f1': 0.9076, 'oracle_f1': 0.955, 'sample_f1_mean': 0.8736, 'sample_f1_pct_zero': 7.03}\n  conclusion: success\n\n=== exp_conll_n16_s123_v2 === [DONE]\n  hyp: CoNLL N=16 (seed=123, v2): retry after previous failure on 5090 (damaged checkpoint). Extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003.\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.9071, 'oracle_f1': 0.9625, 'sample_f1_mean': 0.8676, 'sample_f1_pct_zero': 7.52}\n  conclusion: success\n\n=== exp_scierc_mf4_v2_s42 === [PREPARING]\n  hyp: \n  seed=N/A, dataset=N/A\n\n=== exp_frontier_sc_claude_sonnet4 === [DONE]\n  hyp: Frontier model Claude Sonnet 4 on FewNERD SC (200 instances, N=8, T=1.0): if correlation-selection gap persists across model families (GPT + Claude + Gemini + DeepSeek), the findin\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.6068, 'mv_f1': 0.6226, 'oracle_f1': 0.6544, 'degeneracy_rate': 0.74}\n  conclusion: success\n\n=== exp_e2_pretrained_conll === [DONE]\n  hyp: E2 pre-trained baseline: Qwen2.5-7B-Instruct (unfinetuned) on CoNLL SC pipeline N=8 T=1.0. Cross-dataset validation of pre-trained baseline. Together with FewNERD baseline, shows w\n  seed=42, dataset=N/A\n  conclusion: success\n\n=== exp_frontier_sc_gpt55_fewnerd_v2 === [DONE]\n  hyp: Frontier model GPT-5.5 on FewNERD SC (200 instances, N=8, T=1.0): if correlation-selection gap persists in frontier models, the finding is fundamental and not a model capability li\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.6382, 'mv_f1': 0.6521, 'oracle_f1': 0.7203, 'degeneracy_rate': 0.5}\n  conclusion: success\n\n=== exp_fewnerd_mf4_v2_s456 === [PREPARING]\n  hyp: MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). Third seed completing 3-seed set for statistical power.\n  seed=N/A, dataset=N/A\n\n=== exp_fewnerd_n16_s123 === [DONE]\n  hyp: FewNERD N=16 (seed=123): extending N-scaling curve to N=16 for Qwen3-8B-FT. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) sc\n  seed=N/A, dataset=N/A\n  metrics: {'greedy_f1': 0.7888, 'oracle_f1': 0.9147}\n  conclusion: success\n\n=== exp_fewnerd_n16_s42 === [DONE]\n  hyp: FewNERD N=16 (seed=42): extending N-scaling curve to N=16 for Qwen3-8B-FT. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) sca\n  seed=N/A, dataset=N/A\n  metrics: {'greedy_f1': 0.7886, 'oracle_f1': 0.9059}\n  conclusion: success\n\n=== exp_fewnerd_t12_s456 === [DONE]\n  hyp: FewNERD temperature ablation (T=1.2, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT.\n  seed=456, dataset=N/A\n  metrics: {'greedy_f1': 0.7885, 'oracle_f1': 0.8775, 'degeneracy_rate': None}\n  conclusion: success\n\n=== exp_fewnerd_mf4v2_s42 === [PREPARING]\n  hyp: \n  seed=N/A, dataset=N/A\n\n=== exp_fewnerd_mf4v2_s123 === [PREPARING]\n  hyp: \n  seed=N/A, dataset=N/A\n\n=== exp_14b_inference_fewnerd === [DONE]\n  hyp: 14B Qwen2.5 inference on FewNERD (N∈{1,2,4,8}): primary dataset should show oracle scaling law F1(N)=a-b*N^(-c) consistent at 14B scale, filling the scaling curve between 7B and 32\n  seed=42, dataset=N/A\n  conclusion: success\n\n=== exp_fewnerd_mf4_v2_s42 === [DONE]\n  hyp: MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=42 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1. 3-seed statistical power.\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.7883, 'oracle_f1': 0.8783, 'sample_f1_mean': 0.6123, 'sample_f1_std': 0.3913, 'sample_f1_pct_zero': 23.09, 'n_greedy_f1_zero_filtered': 3883}\n  conclusion: negative\n\n=== exp_fewnerd_mf4_v2_s123 === [DONE]\n  hyp: MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1. 3-seed statistical power.\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.7883, 'oracle_f1': 0.8891, 'sample_f1_mean': 0.6364, 'sample_f1_std': 0.3819, 'sample_f1_pct_zero': 20.49, 'n_greedy_f1_zero_filtered': 3880}\n  conclusion: success\n\n=== exp_fewnerd_n16_s456_v2 === [RUNNING]\n  hyp: FewNERD N=16 (seed=456, v2 rerun): data lost in previous run. Extending N-scaling curve to N=16 for Qwen3-8B-FT, critical for F1(N)=a-b*N^(-c) scaling law. Third seed for 3-seed st\n  seed=456, dataset=N/A\n\n=== exp_fewnerd_7b_n16_s42 === [DONE]\n  hyp: FewNERD N=16 with Qwen2.5-7B: extending N-scaling curve to N=16 for 7B model. At N=8 the 7B model shows diminishing oracle gains; N=16 tests whether the plateau continues or breaks\n  seed=42, dataset=N/A\n  conclusion: failed\n\n=== exp_fewnerd_n16_s456 === [DONE]\n  hyp: FewNERD N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) sc\n  seed=456, dataset=N/A\n  conclusion: failed\n\n=== exp_e2_pretrained_fewnerd === [RUNNING]\n  hyp: E2 pre-trained baseline: Qwen2.5-7B-Instruct (unfinetuned) on FewNERD SC pipeline N=8 T=1.0. Tests whether correlation-selection gap exists without task-specific fine-tuning. If ga\n  seed=42, dataset=N/A\n\n=== exp_conll_mf4_s456 === [DONE]\n  hyp: MF4 pipeline fix: CoNLL N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). Extends exp_conll_t10_s42 to 3-seed set for statistical power.\n  seed=456, dataset=N/A\n  conclusion: killed\n\n=== exp_frontier_sc_gemini25pro === [RUNNING]\n  hyp: Frontier model Gemini 2.5 Pro on FewNERD SC (200 inst, N=8, T=1.0): 4-family cross-validation. If correlation-selection gap persists across GPT + Claude + Gemini + DeepSeek, the fi\n  seed=42, dataset=N/A\n\n=== exp_conll_mf4_s123 === [DONE]\n  hyp: MF4 pipeline fix: CoNLL N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). Extends exp_conll_t10_s42 to 3-seed set for statistical power.\n  seed=123, dataset=N/A\n  conclusion: killed\n\n=== exp_fewnerd_t05_s456 === [DONE]\n  hyp: FewNERD temperature ablation (T=0.5, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT.\n  seed=456, dataset=N/A\n  conclusion: success\n\n=== exp_fewnerd_mf4_s456 === [QUEUED]\n  hyp: MF4 pipeline fix: FewNERD N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1 metric. Required for 3-seed stati\n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== exp_fewnerd_mf4_s123 === [QUEUED]\n  hyp: MF4 pipeline fix: FewNERD N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1 metric. Required for 3-seed stati\n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== exp_fewnerd_mf4_s42 === [QUEUED]\n  hyp: MF4 pipeline fix: FewNERD N=8 T=1.0 seed=42 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1 metric. Required for 3-seed statis\n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== exp_14b_inference_conll === [DONE]\n  hyp: 14B Qwen2.5 inference on CoNLL (N∈{1,2,4,8}): filling scale curve between 8B (greedy F1=0.907) and 32B. Tests whether 14B shows intermediate behavior in SC diagnostic metrics.\n  seed=42, dataset=N/A\n  conclusion: killed\n\n=== exp_conll_n16_s456 === [DONE]\n  hyp: CoNLL N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a\n  seed=N/A, dataset=N/A\n  conclusion: failed\n\n=== exp_conll_n16_s123 === [DONE]\n  hyp: CoNLL N=16 (seed=123): extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a\n  seed=N/A, dataset=N/A\n  conclusion: failed\n\n=== exp_scierc_n16_s456 === [DONE]\n  hyp: SciERC N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT on SciERC. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*\n  seed=456, dataset=N/A\n  conclusion: success\n\n=== exp_scierc_n16_s123 === [DONE]\n  hyp: SciERC N=16 (seed=123): extending N-scaling curve to N=16 for Qwen3-8B-FT on SciERC. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*\n  seed=123, dataset=N/A\n  conclusion: success\n\n=== exp_scierc_t12_s456 === [DONE]\n  hyp: SciERC temperature ablation (T=1.2, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.\n  seed=N/A, dataset=N/A\n  metrics: {'greedy_f1': 0.663, 'oracle_f1': 0.782, 'degeneracy_pct': 14.1}\n  conclusion: success\n\n=== exp_conll_n16_s42 === [DONE]\n  hyp: CoNLL N=16 ablation (T=1.0, seed=42): test whether doubling sample count from N=8 to N=16 improves SC diagnostic correlation and oracle F1 on CoNLL-2003. Qwen3-8B-FT.\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.908, 'oracle_f1': 0.959, 'degeneracy_pct': 7.8}\n  conclusion: success\n\n=== exp_scierc_t08_s123 === [DONE]\n  hyp: SciERC temperature ablation (T=0.8, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.662, 'oracle_f1': 0.773, 'degeneracy_pct': 11.2}\n  conclusion: success\n\n=== exp_scierc_t08_s456 === [DONE]\n  hyp: SciERC temperature ablation (T=0.8, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.\n  seed=N/A, dataset=N/A\n  metrics: {'greedy_f1': 0.664, 'oracle_f1': 0.769, 'degeneracy_pct': 11.9}\n  conclusion: success\n\n=== exp_scierc_t05_s456 === [DONE]\n  hyp: SciERC temperature ablation (T=0.5, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.\n  seed=N/A, dataset=N/A\n  metrics: {'greedy_f1': 0.663, 'oracle_f1': 0.746, 'degeneracy_pct': 10.3}\n  conclusion: success\n\n=== exp_scierc_t12_s123 === [DONE]\n  hyp: SciERC temperature ablation (T=1.2, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.664, 'oracle_f1': 0.788, 'degeneracy_pct': 13.9}\n  conclusion: success\n\n=== exp_scierc_t05_s123 === [DONE]\n  hyp: SciERC temperature ablation (T=0.5, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.665, 'oracle_f1': 0.743, 'degeneracy_pct': 10}\n  conclusion: success\n\n=== exp_fewnerd_t08_s456 === [DONE]\n  hyp: FewNERD T-ablation seed=456 (T=0.8): third seed for T=0.8 sweet-spot, providing 3-seed statistical power for the key operating point. With seeds 42/123/456, can compute confidence \n  seed=456, dataset=N/A\n  metrics: {'greedy_f1': 0.788, 'oracle_f1': 0.877, 'degeneracy_pct': 16.3}\n  conclusion: success\n\n=== exp_fewnerd_t12_s123 === [DONE]\n  hyp: FewNERD T-ablation seed=123 replication (T=1.2): second seed for statistical power on T=1.2 negative result (over-diversification, 28.2% degeneracy, lowest rho_SJ=0.136 in seed=42)\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.789, 'oracle_f1': 0.887, 'degeneracy_pct': 24.7}\n  conclusion: negative\n\n=== exp_fewnerd_t08_s123 === [DONE]\n  hyp: FewNERD T-ablation seed=123 replication (T=0.8): second seed for statistical power on T=0.8 sweet-spot hypothesis (best rho_advantage=0.102 SJ over Fleiss, balanced oracle headroom\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.789, 'oracle_f1': 0.884, 'degeneracy_pct': 16.7}\n  conclusion: success\n\n=== exp_fewnerd_t05_s123 === [DONE]\n  hyp: FewNERD T-ablation seed=123 replication (T=0.5): second seed for statistical power on T=0.5 findings (highest rho_SJ=0.267, lowest oracle headroom=6.85% in seed=42). Confirms wheth\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.789, 'oracle_f1': 0.864, 'degeneracy_pct': 13.5}\n  conclusion: success\n\n=== exp_32b_inference_fewnerd === [DONE]\n  hyp: 32B fine-tuned model (Qwen2.5-32B-Instruct QLoRA, best checkpoint-32000) FewNERD inference with N=8 SC sampling. Scaling from 8B→32B should improve per-sample quality and strengthe\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.8, 'oracle_f1': 0.879}\n  conclusion: success\n\n=== exp_hidden_state_probe_fulldata === [DONE]\n  hyp: Hidden states of fine-tuned Qwen3-8B encode entity quality information that a linear probe can detect with AUROC significantly above chance, even under GroupKFold (no instance leak\n  seed=42,123,456, dataset=N/A\n  conclusion: success\n\n=== exp_conll_t10_s42 === [DONE]\n  hyp: CoNLL T=1.0 baseline (seed=42): fills the gap in the temperature ablation matrix (T=0.5/0.8/1.2 already complete with 3 seeds). T=1.0 is the default sampling temperature and should\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.9077, 'oracle_f1': 0.9503, 'sample_f1_mean': 0.871, 'sample_f1_pct_zero': 7.53}\n  conclusion: success\n\n=== exp_scierc_probe === [DONE]\n  hyp: SciERC hidden state probe: test if linear classifier on last-layer hidden states can predict entity quality (match vs non-match against gold). If AUROC ≈ 0.98 (consistent with FewN\n  seed=42, dataset=N/A\n  conclusion: success\n\n=== exp_conll_t12_s456 === [DONE]\n  hyp: CoNLL temperature ablation (T=1.2, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.\n  seed=456, dataset=N/A\n  metrics: {'greedy_f1': 0.9071, 'oracle_f1': 0.9452, 'rho_SJ_F1_full': 0.4553, 'rho_SJ_F1_conditional': 0.4259, 'degeneracy_rate_pct': 8.34}\n  conclusion: success\n\n=== exp_conll_t08_s456 === [DONE]\n  hyp: CoNLL temperature ablation (T=0.8, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.\n  seed=456, dataset=N/A\n  metrics: {'greedy_f1': 0.9064, 'oracle_f1': 0.9407, 'rho_SJ_F1_full': 0.4877, 'rho_SJ_F1_conditional': 0.4756, 'degeneracy_rate_pct': 6.29}\n  conclusion: success\n\n=== exp_conll_t05_s456 === [DONE]\n  hyp: CoNLL temperature ablation (T=0.5, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.\n  seed=456, dataset=N/A\n  metrics: {'greedy_f1': 0.9075, 'oracle_f1': 0.9338, 'rho_SJ_F1_full': 0.4549, 'rho_SJ_F1_conditional': 0.469, 'degeneracy_rate_pct': 5.62}\n  conclusion: success\n\n=== exp_fewnerd_t05_s42 === [DONE]\n  hyp: FewNERD temperature ablation (T=0.5): test how lower temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwen3-8B-F\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.7884, 'oracle_f1': 0.8569, 'sample_f1_mean': 0.7154, 'degeneracy_rate': 0.146, 'rho_SJ_F1_full': 0.2667, 'rho_SJ_F1_conditional': 0.2988, 'rho_fleiss_F1_full': 0.2231, 'rho_fleiss_F1_conditional': 0.2338, 'rho_logprob_F1_full': 0.3558, 'rho_logprob_F1_conditional': 0.3025}\n  conclusion: success\n\n=== exp_fewnerd_t08_s42 === [DONE]\n  hyp: FewNERD temperature ablation (T=0.8): test how moderate-low temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwe\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.7884, 'oracle_f1': 0.875, 'sample_f1_mean': 0.6622, 'degeneracy_rate': 0.1897, 'rho_SJ_F1_full': 0.2062, 'rho_SJ_F1_conditional': 0.2248, 'rho_fleiss_F1_full': 0.1038, 'rho_logprob_F1_full': 0.2323, 'rho_logprob_F1_conditional': 0.1984}\n  conclusion: success\n\n=== exp_fewnerd_t12_s42 === [DONE]\n  hyp: FewNERD temperature ablation (T=1.2): test how higher temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwen3-8B-\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.7888, 'oracle_f1': 0.875, 'sample_f1_mean': 0.5524, 'degeneracy_rate': 0.2818, 'rho_SJ_F1_full': 0.136, 'rho_SJ_F1_conditional': 0.2125, 'rho_fleiss_F1_full': 0.0605, 'rho_logprob_F1_conditional': 0.1912}\n  conclusion: negative\n\n=== exp_conll_t12_s123 === [DONE]\n  hyp: CoNLL temperature ablation (T=1.2, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.9072, 'oracle_f1': 0.955, 'sample_f1_mean': 0.8438, 'sample_f1_pct_zero': 9.1}\n  conclusion: success\n\n=== exp_conll_t08_s123 === [DONE]\n  hyp: CoNLL temperature ablation (T=0.8, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.9068, 'oracle_f1': 0.9466, 'sample_f1_mean': 0.8897, 'sample_f1_pct_zero': 6.1}\n  conclusion: success\n\n=== exp_conll_t05_s123 === [DONE]\n  hyp: CoNLL temperature ablation (T=0.5, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.\n  seed=123, dataset=N/A\n  metrics: {'greedy_f1': 0.9073, 'oracle_f1': 0.9351, 'sample_f1_mean': 0.901, 'sample_f1_pct_zero': 5.5}\n  conclusion: success\n\n=== exp_qwen25_32b_fewnerd === [DONE]\n  hyp: Qwen2.5-32B-Instruct QLoRA fine-tuning on FewNERD: scaling model from 8B→32B should improve per-sample NER quality, enabling stronger SC diagnostic signals. LoRA r=32, alpha=64, ta\n  seed=42, dataset=N/A\n  output_dir: /root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-32b-fewnerd-qlora-s42\n  metrics: {'lora_alpha': 64}\n  conclusion: success\n\n=== exp_conll_t_ablation_t12 === [DONE]\n  hyp: CoNLL temperature ablation (T=1.2): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.9071, 'oracle_f1': 0.9514, 'degen_pct': 9.22, 'sample_f1_mean': 0.8452}\n  conclusion: success\n\n=== exp_conll_t_ablation_t08 === [DONE]\n  hyp: CoNLL temperature ablation (T=0.8): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.9069, 'oracle_f1': 0.9464, 'degen_pct': 6.57, 'sample_f1_mean': 0.8854}\n  conclusion: success\n\n=== exp_conll_t_ablation_t05 === [DONE]\n  hyp: CoNLL temperature ablation (T=0.5): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.9077, 'oracle_f1': 0.9372, 'degen_pct': 5.64, 'sample_f1_mean': 0.8993}\n  conclusion: success\n\n=== exp_conll_t05_s42 === [DONE]\n  hyp: CoNLL T=0.5 temperature point: test low temperature on CoNLL2003 to extend cross-dataset T-ablation evidence beyond SciERC and FewNERD. N=8, Qwen3-8B-FT-CoNLL, seed=42. Complements\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1': 0.9083, 'oracle_f1': 0.9376, 'degen_pct': 5.64, 'sample_f1_mean': 0.8994}\n  conclusion: success\n\n=== exp_spider_sc_pilot === [DONE]\n  hyp: SC diagnostic cascade (degeneracy, agreement-correctness correlation, failure mode classification F1-F4) validated on NER structured generation will also manifest in SQL structured\n  seed=42, dataset=N/A\n  metrics: {'greedy_acc': 0.7653, 'mv_acc': 0.7704, 'mv_gain_pp': 0.51, 'degeneracy_rate': 0.8724, 'F1_degeneracy_rate': 0.872, 'nondegen_n': 25, 'nondegen_greedy_acc': 0.32, 'nondegen_mv_acc': 0.36, 'nondegen_oracle_acc': 0.64, 'nondegen_spearman_rho': 0.13}\n  conclusion: success\n\n=== exp_fewrel_re_sc === [DONE]\n  hyp: SC consensus construction improves RE micro-F1 over greedy decoding on FewRel (16 relation types, Wikipedia domain), extending cross-task universality evidence beyond SciERC and Do\n  seed=42, dataset=N/A\n  metrics: {'greedy_micro_f1': 0.0751, 'construction_micro_f1': 0.0881, 'majority_vote_f1_mean': 0.0591, 'oracle_f1_mean': 0.1768, 'degeneracy_rate': 0.0586}\n  conclusion: negative\n\n=== exp_b_frontier_sc_fewnerd === [DONE]\n  hyp: The correlation-selection gap in structured self-consistency (where agreement correlates with accuracy but majority voting fails to improve over greedy) persists even with frontier\n  seed=42, dataset=N/A\n  conclusion: failed\n\n=== exp_docred_re_sc === [DONE]\n  hyp: SC diagnostic cascade (degeneracy, correlation-selection gap, F1-F4 failure modes) generalizes from NER to document-level RE on DocRED, with Qwen2.5-7B-Instruct showing similar fai\n  seed=42, dataset=N/A\n  metrics: {'greedy_f1_mean': 0.0284, 'construction_f1_mean': 0.0338, 'majority_vote_f1_mean': 0.0263, 'oracle_f1_mean': 0.0999, 'greedy_micro_f1': 0.0297, 'construction_micro_f1': 0.0323, 'degeneracy_rate': 0.035, 'nondegen_construction_greedy_diff': 0.0055}\n  conclusion: success\n\n=== exp_b1_scd === [PENDING]\n  hyp: Self-Consistency Distillation via theta2n construction pseudo-labels can teach Qwen3-8B-FT to internalize SC benefits: after iterative SCD (M0→M1→M2→M3), greedy F1 should approach \n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== eval_scd_fewnerd_fallback === [PREPARING]\n  hyp: \n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== exp_b1_scd_fewnerd_curriculum_q === [DONE]\n  hyp: Q variant SCD with curriculum ordering: use B2 entity verifier confidence to stratify pseudo-labels (conf>0.8→Round1, 0.5-0.8→Round2, conf<0.5→discard). Curriculum by verifier conf\n  seed=43, dataset=N/A\n  metrics: {'eval_greedy_f1': 0.7866, 'eval_greedy_precision': 0.7663, 'eval_greedy_recall': 0.808, 'eval_instance_avg_f1': 0.7809, 'baseline_greedy_f1': 0.748}\n  conclusion: negative\n\n=== exp_b1_scd_fewnerd_standard === [DONE]\n  hyp: Standard Self-Consistency Distillation on FewNERD: fine-tune Qwen3-8B-FT with theta2n construction pseudo-labels (32,565 instances) mixed 1:1 with gold data. Greedy F1 after SCD sh\n  seed=42, dataset=N/A\n  conclusion: negative\n\n=== exp_b1_scd_threshold_ablation === [DONE]\n  hyp: Construction threshold sweep for SCD pseudo-label generation on FewNERD: θ∈{1/N, 2/N, 3/N, 0.5}. Higher θ = more conservative pseudo-labels (higher precision, lower recall). Optima\n  seed=42, dataset=N/A\n  conclusion: failed\n\n=== exp_tlow_fewnerd_inference === [DONE]\n  hyp: Lower temperature (T=0.5) sampling on FewNERD produces less diverse but higher-quality samples that, when combined with T=1.0 samples in heterogeneous-temperature selection, improv\n  seed=42, dataset=N/A\n  conclusion: success\n\n=== exp_14b_inference_scierc === [DONE]\n  hyp: 14B Qwen2.5 inference on SciERC (N∈{1,2,4,8,16}): correlation-selection gap pattern should be consistent at 14B scale with intermediate degeneracy rates between 7B and 32B.\n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== exp_qwen25_14b_fewnerd === [DONE]\n  hyp: The correlation-selection gap pattern is consistent at 14B scale, filling the gap between 8B and 32B. Qwen2.5-14B QLoRA fine-tuned on FewNERD should show intermediate degeneracy ra\n  seed=42, dataset=N/A\n  conclusion: success\n\n=== exp_b1_scd_conll_control === [DONE]\n  hyp: Negative control: SCD on CoNLL where construction gain is negative (-0.4pp, high degeneracy 70%). If SCD learns from construction pseudo-labels, it should NOT improve greedy F1 on \n  seed=42, dataset=N/A\n  metrics: {'pre_scd_greedy_f1': 0.9078, 'post_scd_greedy_f1': 0.9184}\n  conclusion: negative\n\n=== exp_b2_v2_multi_domain_joint === [PREPARING]\n  hyp: Joint multi-domain training (CoNLL+SciERC+FewNERD LODO) improves entity verifier AUC and cross-domain construction F1 by exposing the model to diverse entity patterns. Tests whethe\n  seed=N/A, dataset=N/A\n  metrics: {'fold3_fewnerd_f1_delta': -0.008}\n  conclusion: negative\n\n=== exp_b2_entity_verifier === [PREPARING]\n  hyp: An XGBoost/LightGBM entity-level verifier trained on agreement_count, VC, LP features can predict whether entity candidates are in gold annotations, enabling post-hoc filtering or \n  seed=N/A, dataset=N/A\n  metrics: {'oof_path_a_f1_delta': 0.003, 'oof_path_b_f1_delta': -0.0157, 'oof_greedy_f1': 0.8216, 'oof_path_a_f1': 0.8246, 'oof_majority_vote_f1': 0.8048}\n  conclusion: negative\n\n=== exp_qwen25_7b_fewnerd === [DONE]\n  hyp: Qwen2.5-7B QLoRA fine-tuned on FewNERD will produce structurally diverse samples enabling self-consistency-based entity extraction with meaningful LP-weighted consensus signals, co\n  seed=42, dataset=N/A\n  conclusion: success\n\n=== exp_wnut17_qwen25_7b === [DONE]\n  hyp: The correlation-selection gap extends to noisy social media NER (WNUT-17). Unlike formal-domain datasets (SciERC/CoNLL/FewNERD), WNUT-17 has higher surface-level noise which may af\n  seed=42, dataset=N/A\n  conclusion: negative\n\n=== exp_llama_fewnerd_inference === [DONE]\n  hyp: LLaMA-3.1-8B fine-tuned on FewNERD shows the same structured self-consistency phenomena (degeneracy, LP-F1 alignment, signal ranking) as Qwen models, providing cross-model generali\n  seed=42,123,456, dataset=N/A\n  conclusion: success\n\n=== exp_entity_construction === [DONE]\n  hyp: Entity-level majority vote construction is the correct self-consistency analogy for structured IE: instead of selecting the best instance-level output, assemble a better output fro\n  seed=42, dataset=N/A\n  conclusion: success\n\n=== exp_llama_fewnerd_lora === [DONE]\n  hyp: LLaMA-based model with LoRA fine-tuning on Few-NERD can provide a second model family (beyond Qwen) for cross-model generalization evidence of structured self-consistency phenomena\n  seed=42, dataset=N/A\n  conclusion: success\n\n=== hidden_state_probe_conll_full === [DONE]\n  hyp: \n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== hidden_state_probe_conll_v2 === [DONE]\n  hyp: \n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== exp_031_fewnerd_t12 === [DONE]\n  hyp: FewNERD T=1.2 temperature ablation: test if higher temperature reduces degeneracy on FewNERD as observed on SciERC\n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== exp_030_conll_t12 === [DONE]\n  hyp: CoNLL T=1.2 temperature ablation: test if higher temperature reduces degeneracy on CoNLL as observed on SciERC\n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== mbr_pilot === [DONE]\n  hyp: \n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== dgs_pilot === [DONE]\n  hyp: Degeneracy-Gated Selection (DGS) validates Two-Condition Theory: using degeneracy rate as gating mechanism to switch between greedy (degenerate) and LP selection (non-degenerate), \n  seed=N/A, dataset=N/A\n  conclusion: killed\n\n=== exp_fewnerd_s789_n8 === [DONE]\n  hyp: FewNERD seed789 (4th seed) for statistical CI strengthening: 4-seed protocol provides tighter confidence intervals on LP selection gain and DGS effectiveness in low-degeneracy regi\n  seed=789, dataset=N/A\n  metrics: {'greedy_f1': 0.7478, 'oracle_f1': 0.8714, 'degen_rate': 0.1177, 'degen_rate_source': 'unified_metrics_constant_f1_gold_filtered', 'lp_sel_f1': 0.7614, 'dgs_f1': 0.7621, 'four_seed_mean_greedy': 0.7481}\n  conclusion: success\n\n=== exp_026_t12_seed456 === [DONE]\n  hyp: Temperature ablation (T=1.2, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\n  seed=456, dataset=N/A",
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

_source line 38_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01VcPLqBsVWuUneiqo7Fky1o`</summary>

```json
{
  "server": "autodl-5090",
  "command": "ls -d /root/autodl-tmp/struct_self_consist_ie/output/conll* /root/autodl-tmp/struct_self_consist_ie/output/scierc*",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "39b7a2ef-6609-44c2-8d31-4ec1eee95b43",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GAv8MKQAPW2XVDsfNzZ1Uw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1026,
      "cache_read_input_tokens": 37402,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1026
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

_source line 39 · 2026-05-21T09:28:20.433Z_

<details><summary>↩ Tool result · `toolu_01VcPLqBsVWuUneiqo7Fky1o`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed123\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed456\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_s123\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_s456\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_seed123_v2\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_seed456_v2\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed123\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed42\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed456\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.37}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "7627ecfb-cec2-4790-98f4-66433468a050",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed123\\\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed456\\\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_s123\\\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_s456\\\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_seed123_v2\\\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_seed456_v2\\\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed123\\\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed42\\\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed456\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.37}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed123\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed456\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_s123\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_s456\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_seed123_v2\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_seed456_v2\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed123\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed42\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed456\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.37}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 40_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clearer picture. Let me organize what I know:

**FewNERD directories on server:**
- fewnerd_mf4_seed123, fewnerd_mf4_seed42, fewnerd_mf4_seed456 (MF4 v1 - might be killed/old)
- fewnerd_mf4v2_seed123, fewnerd_mf4v2_seed42, fewnerd_mf4v2_seed456 (MF4 v2 - new pipeline)
- fewnerd_seed789_merged


- CoNLL has similar variants with MF4 v1 and N16 versions, while SciERC only has the MF4 v2 runs across three seeds. I also see there's a registry experiment for FewNERD MF4 v2 with seed 42 that's marked as done.

Looking at the results, the FewNERD experiments show greedy F1 scores around 0.78-0.79 with oracle F1 around 0.88-0.89, while the CoNLL experiments perform much better with greedy F1 around 0.90-0.91 and oracle F1 around 0.94-0.95. The FewNERD seed 456 variant is still being prepared, and there's a partial entry for a CoNLL T10 experiment that appears to be cut off. The MF4v2 experiments use seeds 42, 123, and 456 — the exact set the reviewer flagged. Looking at the α_crit table more carefully, I'm noticing something odd: the FewNERD greedy average of 0.7482 is suspiciously close to just the seed 789 value (0.7478), while the MF4v2 results for seeds 42 and 123 show much higher greedy_f1 scores around 0.7883. This suggests the α_crit table might be pulling from older pipeline data rather than the current metrics.

I need to SSH in and check the actual report.json files for these experiments — specifically the fewnerd_seed789_merged file to see which metric was used, the older FewNERD runs with seeds 123 and 456, and the MF4v2 report files to verify what's actually being reported.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "4b11cab3-b58d-46ba-8039-8d2f79c325dd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KqwTmffY1YJcW3wvqU9iv6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13183,
      "cache_read_input_tokens": 38428,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13183
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

_source line 41_

关键发现：注册表显示 MF4v2 实验明确标注 "Replaces exp_021 which used incompatible greedy_macro_f1"。现在去服务器检查实际 report.json 文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "68e12d65-26bf-4617-97ea-1b05c2e9455b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KqwTmffY1YJcW3wvqU9iv6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13183,
      "cache_read_input_tokens": 38428,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13183
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

_source line 42_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_017JQ42r3gosJJcJUyqsTMik`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged -name \"*.json\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "03d2bee3-ab76-4172-817b-9289a0c3e9ae",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KqwTmffY1YJcW3wvqU9iv6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13183,
      "cache_read_input_tokens": 38428,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13183
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

_source line 43 · 2026-05-21T09:28:43.190Z_

<details><summary>↩ Tool result · `toolu_017JQ42r3gosJJcJUyqsTMik`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/analysis.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/full_signal_analysis.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/four_seed_summary.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "cf867991-ce59-4c43-be94-09f0f6bdee5f",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/analysis.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/full_signal_analysis.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/four_seed_summary.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.35}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/analysis.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/full_signal_analysis.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/four_seed_summary.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 44_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_016Z45bMfv2ngcbo1KKLiPXY`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed42 -name \"*.json\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "83ce3c80-cdc6-4856-ae09-d50ae050e325",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KqwTmffY1YJcW3wvqU9iv6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13183,
      "cache_read_input_tokens": 38428,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13183
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

_source line 45 · 2026-05-21T09:28:44.195Z_

<details><summary>↩ Tool result · `toolu_016Z45bMfv2ngcbo1KKLiPXY`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "54f74546-1a21-4739-bcc8-28a6716b56e0",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.36}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 46_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01PLnz43PPSUTcYXx5fZTcYK`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed123 -name \"*.json\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "475605f0-1c58-460d-af2c-14a2548030c8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KqwTmffY1YJcW3wvqU9iv6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13183,
      "cache_read_input_tokens": 38428,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13183
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

_source line 47 · 2026-05-21T09:28:45.132Z_

<details><summary>↩ Tool result · `toolu_01PLnz43PPSUTcYXx5fZTcYK`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "4443bf46-04b9-4487-8456-ee8ac5dcab57",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.36}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 48_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01PwsHk4HXgdLvQS15N3gc1K`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed456 -name \"*.json\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "8a1d14d3-2e3f-4431-b05f-ebdbf586d961",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KqwTmffY1YJcW3wvqU9iv6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13183,
      "cache_read_input_tokens": 38428,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13183
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

_source line 49 · 2026-05-21T09:28:45.608Z_

<details><summary>↩ Tool result · `toolu_01PwsHk4HXgdLvQS15N3gc1K`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed456/report.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "cebfa7f6-04d1-424a-85d7-357c98f6d962",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed456/report.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.38}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed456/report.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 50_

<details><summary>Logged reasoning block</summary>

```text
So:
- fewnerd_seed789_merged: has analysis.json, full_signal_analysis.json, four_seed_summary.json (but no report.json!)
- fewnerd_mf4v2_seed42: empty (no JSON files)
- fewnerd_mf4v2_seed123: empty (no JSON files)
- fewnerd_mf4v2_seed456: has report.json

Wait, the registry says exp_fewnerd_mf4_v2_s42 is DONE with metrics, and exp_fewnerd_mf4_v2_s123 is DONE. 

The output directories might be named differently than I expected, so I should check the MF4 v1 directories as well and track down where the actual results for the MF4v2 seed 42 and 123 experiments ended up.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "cb132358-7d5e-4728-998c-fed460f6ae75",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SvenJ1QtxS2fe6DXCAgtct",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2255,
      "cache_read_input_tokens": 51611,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2255
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_019gtCnnDNqevnLHxkHppppN`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed42 -name \"*.json\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "92f2e23a-88e0-4beb-adc2-87c69bbd039a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SvenJ1QtxS2fe6DXCAgtct",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2255,
      "cache_read_input_tokens": 51611,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2255
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

_source line 52 · 2026-05-21T09:28:52.189Z_

<details><summary>↩ Tool result · `toolu_019gtCnnDNqevnLHxkHppppN`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "493c6954-062f-44b4-9104-37aa94446dbc",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.36}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 53_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01H5LywqVNvyVDZx29Y9dwNt`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed123 -name \"*.json\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "1d7f4f85-0306-4123-8355-a57dcbe51188",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SvenJ1QtxS2fe6DXCAgtct",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2255,
      "cache_read_input_tokens": 51611,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2255
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

_source line 54 · 2026-05-21T09:28:52.995Z_

<details><summary>↩ Tool result · `toolu_01H5LywqVNvyVDZx29Y9dwNt`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "f494e407-ed08-4e35-963e-3a79b1cc6ab3",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.35}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 55_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01DjnwfWBBAwhToSXzP9QSUV`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4_seed456 -name \"*.json\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "f9d6e2e4-8440-4324-8b05-ba5c29b36c26",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SvenJ1QtxS2fe6DXCAgtct",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2255,
      "cache_read_input_tokens": 51611,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2255
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

_source line 56 · 2026-05-21T09:28:53.842Z_

<details><summary>↩ Tool result · `toolu_01DjnwfWBBAwhToSXzP9QSUV`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "b5f55d35-0bc4-4322-9964-aab27581e154",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.36}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 57_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01EmSe4MDomhWUUQgeQzETRP`</summary>

```json
{
  "server": "autodl-5090",
  "command": "cat /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/analysis.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "076fd4e8-79ad-4788-beea-caf49c0c2f2e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SvenJ1QtxS2fe6DXCAgtct",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2255,
      "cache_read_input_tokens": 51611,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2255
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

_source line 58 · 2026-05-21T09:28:54.371Z_

<details><summary>↩ Tool result · `toolu_01EmSe4MDomhWUUQgeQzETRP`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"meta\\\": {\\n    \\\"input\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/samples.jsonl\\\",\\n    \\\"n_total\\\": 37648,\\n    \\\"n_filtered\\\": 32565,\\n    \\\"n_samples\\\": 8\\n  },\\n  \\\"basic\\\": {\\n    \\\"greedy_macro_f1\\\": 0.7477603920094339,\\n    \\\"oracle_macro_f1\\\": 0.8714430391776531,\\n    \\\"headroom_pp\\\": 12.368264716821919,\\n    \\\"zero_f1_rate_pct\\\": 4.66451711960694,\\n    \\\"degeneracy_rate_pct\\\": 11.773376324274528,\\n    \\\"lp_range_median\\\": 0.07035905898627522\\n  },\\n  \\\"qe\\\": {\\n    \\\"LP\\\": {\\n      \\\"auroc\\\": 0.5994,\\n      \\\"spearman_global\\\": 0.1788,\\n      \\\"spearman_global_p\\\": 4.5155543415619905e-232,\\n      \\\"spearman_conditional\\\": 0.176,\\n      \\\"spearman_conditional_p\\\": 2.8357968088845245e-198\\n    },\\n    \\\"SJ\\\": {\\n      \\\"auroc\\\": 0.5139,\\n      \\\"spearman_global\\\": 0.253,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.207,\\n      \\\"spearman_conditional_p\\\": 3.378122441777232e-275\\n    },\\n    \\\"FK\\\": {\\n      \\\"auroc\\\": 0.5131,\\n      \\\"spearman_global\\\": 0.1608,\\n      \\\"spearman_global_p\\\": 1.3747764387755347e-187,\\n      \\\"spearman_conditional\\\": 0.02,\\n      \\\"spearman_conditional_p\\\": 0.0006972897086701938\\n    },\\n    \\\"EM\\\": {\\n      \\\"auroc\\\": 0.5033,\\n      \\\"spearman_global\\\": 0.2714,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.4339,\\n      \\\"spearman_conditional_p\\\": 0.0\\n    },\\n    \\\"VC\\\": {\\n      \\\"auroc\\\": 0.5392,\\n      \\\"spearman_global\\\": 0.2673,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.0476,\\n      \\\"spearman_conditional_p\\\": 6.76361927743609e-16\\n    }\\n  },\\n  \\\"selection\\\": {\\n    \\\"LP\\\": {\\n      \\\"f1\\\": 0.7614,\\n      \\\"delta_pp\\\": 1.3647\\n    },\\n    \\\"SJ\\\": {\\n      \\\"f1\\\": 0.6854,\\n      \\\"delta_pp\\\": -6.2399\\n    },\\n    \\\"FK\\\": {\\n      \\\"f1\\\": 0.6745,\\n      \\\"delta_pp\\\": -7.3269\\n    },\\n    \\\"EM\\\": {\\n      \\\"f1\\\": 0.6745,\\n      \\\"delta_pp\\\": -7.3269\\n    },\\n    \\\"VC\\\": {\\n      \\\"f1\\\": 0.7202,\\n      \\\"delta_pp\\\": -2.753\\n    }\\n  },\\n  \\\"bootstrap\\\": {\\n    \\\"LP\\\": {\\n      \\\"mean_delta_pp\\\": 1.3655,\\n      \\\"ci_95_lo_pp\\\": 1.1874,\\n      \\\"ci_95_hi_pp\\\": 1.5404,\\n      \\\"p_value\\\": 0.0,\\n      \\\"significant_005\\\": true\\n    },\\n    \\\"SJ\\\": {\\n      \\\"mean_delta_pp\\\": -6.2407,\\n      \\\"ci_95_lo_pp\\\": -6.5422,\\n      \\\"ci_95_hi_pp\\\": -5.9548,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"FK\\\": {\\n      \\\"mean_delta_pp\\\": -7.3327,\\n      \\\"ci_95_lo_pp\\\": -7.6381,\\n      \\\"ci_95_hi_pp\\\": -7.0294,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"EM\\\": {\\n      \\\"mean_delta_pp\\\": -7.3165,\\n      \\\"ci_95_lo_pp\\\": -7.6397,\\n      \\\"ci_95_hi_pp\\\": -7.0079,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"VC\\\": {\\n      \\\"mean_delta_pp\\\": -2.7559,\\n      \\\"ci_95_lo_pp\\\": -3.0494,\\n      \\\"ci_95_hi_pp\\\": -2.4546,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    }\\n  },\\n  \\\"dgs\\\": {\\n    \\\"dgs_f1\\\": 0.7621,\\n    \\\"dgs_delta_vs_greedy_pp\\\": 1.4329,\\n    \\\"dgs_delta_vs_lp_pp\\\": 0.0682,\\n    \\\"dgs_bootstrap_ci_95\\\": {\\n      \\\"lo_pp\\\": 1.2608,\\n      \\\"hi_pp\\\": 1.6063\\n    },\\n    \\\"n_degenerate\\\": 3834,\\n    \\\"n_nondegenerate\\\": 28731\\n  },\\n  \\\"entity_types\\\": {\\n    \\\"art\\\": {\\n      \\\"count\\\": 4064,\\n      \\\"greedy_f1\\\": 0.7953,\\n      \\\"oracle_f1\\\": 0.8757,\\n      \\\"lp_selection_f1\\\": 0.7951,\\n      \\\"lp_delta_pp\\\": -0.0241,\\n      \\\"zero_f1_rate\\\": 5.5\\n    },\\n    \\\"building\\\": {\\n      \\\"count\\\": 5007,\\n      \\\"greedy_f1\\\": 0.744,\\n      \\\"oracle_f1\\\": 0.8485,\\n      \\\"lp_selection_f1\\\": 0.7418,\\n      \\\"lp_delta_pp\\\": -0.2226,\\n      \\\"zero_f1_rate\\\": 7.1\\n    },\\n    \\\"event\\\": {\\n      \\\"count\\\": 4104,\\n      \\\"greedy_f1\\\": 0.7123,\\n      \\\"oracle_f1\\\": 0.8425,\\n      \\\"lp_selection_f1\\\": 0.7158,\\n      \\\"lp_delta_pp\\\": 0.3579,\\n      \\\"zero_f1_rate\\\": 8.2\\n    },\\n    \\\"location\\\": {\\n      \\\"count\\\": 27235,\\n      \\\"greedy_f1\\\": 0.8142,\\n      \\\"oracle_f1\\\": 0.8989,\\n      \\\"lp_selection_f1\\\": 0.8138,\\n      \\\"lp_delta_pp\\\": -0.0419,\\n      \\\"zero_f1_rate\\\": 4.0\\n    },\\n    \\\"organization\\\": {\\n      \\\"count\\\": 19078,\\n      \\\"greedy_f1\\\": 0.7595,\\n      \\\"oracle_f1\\\": 0.8633,\\n      \\\"lp_selection_f1\\\": 0.763,\\n      \\\"lp_delta_pp\\\": 0.3442,\\n      \\\"zero_f1_rate\\\": 6.5\\n    },\\n    \\\"other\\\": {\\n      \\\"count\\\": 9558,\\n      \\\"greedy_f1\\\": 0.7082,\\n      \\\"oracle_f1\\\": 0.8479,\\n      \\\"lp_selection_f1\\\": 0.7336,\\n      \\\"lp_delta_pp\\\": 2.5359,\\n      \\\"zero_f1_rate\\\": 13.2\\n    },\\n    \\\"person\\\": {\\n      \\\"count\\\": 21565,\\n      \\\"greedy_f1\\\": 0.8374,\\n      \\\"oracle_f1\\\": 0.913,\\n      \\\"lp_selection_f1\\\": 0.8401,\\n      \\\"lp_delta_pp\\\": 0.2785,\\n      \\\"zero_f1_rate\\\": 3.6\\n    },\\n    \\\"product\\\": {\\n      \\\"count\\\": 6231,\\n      \\\"greedy_f1\\\": 0.7129,\\n      \\\"oracle_f1\\\": 0.8402,\\n      \\\"lp_selection_f1\\\": 0.721,\\n      \\\"lp_delta_pp\\\": 0.8158,\\n      \\\"zero_f1_rate\\\": 11.4\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "7803806d-c73e-4ebd-aa0f-24272ccbcc1e",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"meta\\\\\\\": {\\\\n    \\\\\\\"input\\\\\\\": \\\\\\\"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/samples.jsonl\\\\\\\",\\\\n    \\\\\\\"n_total\\\\\\\": 37648,\\\\n    \\\\\\\"n_filtered\\\\\\\": 32565,\\\\n    \\\\\\\"n_samples\\\\\\\": 8\\\\n  },\\\\n  \\\\\\\"basic\\\\\\\": {\\\\n    \\\\\\\"greedy_macro_f1\\\\\\\": 0.7477603920094339,\\\\n    \\\\\\\"oracle_macro_f1\\\\\\\": 0.8714430391776531,\\\\n    \\\\\\\"headroom_pp\\\\\\\": 12.368264716821919,\\\\n    \\\\\\\"zero_f1_rate_pct\\\\\\\": 4.66451711960694,\\\\n    \\\\\\\"degeneracy_rate_pct\\\\\\\": 11.773376324274528,\\\\n    \\\\\\\"lp_range_median\\\\\\\": 0.07035905898627522\\\\n  },\\\\n  \\\\\\\"qe\\\\\\\": {\\\\n    \\\\\\\"LP\\\\\\\": {\\\\n      \\\\\\\"auroc\\\\\\\": 0.5994,\\\\n      \\\\\\\"spearman_global\\\\\\\": 0.1788,\\\\n      \\\\\\\"spearman_global_p\\\\\\\": 4.5155543415619905e-232,\\\\n      \\\\\\\"spearman_conditional\\\\\\\": 0.176,\\\\n      \\\\\\\"spearman_conditional_p\\\\\\\": 2.8357968088845245e-198\\\\n    },\\\\n    \\\\\\\"SJ\\\\\\\": {\\\\n      \\\\\\\"auroc\\\\\\\": 0.5139,\\\\n      \\\\\\\"spearman_global\\\\\\\": 0.253,\\\\n      \\\\\\\"spearman_global_p\\\\\\\": 0.0,\\\\n      \\\\\\\"spearman_conditional\\\\\\\": 0.207,\\\\n      \\\\\\\"spearman_conditional_p\\\\\\\": 3.378122441777232e-275\\\\n    },\\\\n    \\\\\\\"FK\\\\\\\": {\\\\n      \\\\\\\"auroc\\\\\\\": 0.5131,\\\\n      \\\\\\\"spearman_global\\\\\\\": 0.1608,\\\\n      \\\\\\\"spearman_global_p\\\\\\\": 1.3747764387755347e-187,\\\\n      \\\\\\\"spearman_conditional\\\\\\\": 0.02,\\\\n      \\\\\\\"spearman_conditional_p\\\\\\\": 0.0006972897086701938\\\\n    },\\\\n    \\\\\\\"EM\\\\\\\": {\\\\n      \\\\\\\"auroc\\\\\\\": 0.5033,\\\\n      \\\\\\\"spearman_global\\\\\\\": 0.2714,\\\\n      \\\\\\\"spearman_global_p\\\\\\\": 0.0,\\\\n      \\\\\\\"spearman_conditional\\\\\\\": 0.4339,\\\\n      \\\\\\\"spearman_conditional_p\\\\\\\": 0.0\\\\n    },\\\\n    \\\\\\\"VC\\\\\\\": {\\\\n      \\\\\\\"auroc\\\\\\\": 0.5392,\\\\n      \\\\\\\"spearman_global\\\\\\\": 0.2673,\\\\n      \\\\\\\"spearman_global_p\\\\\\\": 0.0,\\\\n      \\\\\\\"spearman_conditional\\\\\\\": 0.0476,\\\\n      \\\\\\\"spearman_conditional_p\\\\\\\": 6.76361927743609e-16\\\\n    }\\\\n  },\\\\n  \\\\\\\"selection\\\\\\\": {\\\\n    \\\\\\\"LP\\\\\\\": {\\\\n      \\\\\\\"f1\\\\\\\": 0.7614,\\\\n      \\\\\\\"delta_pp\\\\\\\": 1.3647\\\\n    },\\\\n    \\\\\\\"SJ\\\\\\\": {\\\\n      \\\\\\\"f1\\\\\\\": 0.6854,\\\\n      \\\\\\\"delta_pp\\\\\\\": -6.2399\\\\n    },\\\\n    \\\\\\\"FK\\\\\\\": {\\\\n      \\\\\\\"f1\\\\\\\": 0.6745,\\\\n      \\\\\\\"delta_pp\\\\\\\": -7.3269\\\\n    },\\\\n    \\\\\\\"EM\\\\\\\": {\\\\n      \\\\\\\"f1\\\\\\\": 0.6745,\\\\n      \\\\\\\"delta_pp\\\\\\\": -7.3269\\\\n    },\\\\n    \\\\\\\"VC\\\\\\\": {\\\\n      \\\\\\\"f1\\\\\\\": 0.7202,\\\\n      \\\\\\\"delta_pp\\\\\\\": -2.753\\\\n    }\\\\n  },\\\\n  \\\\\\\"bootstrap\\\\\\\": {\\\\n    \\\\\\\"LP\\\\\\\": {\\\\n      \\\\\\\"mean_delta_pp\\\\\\\": 1.3655,\\\\n      \\\\\\\"ci_95_lo_pp\\\\\\\": 1.1874,\\\\n      \\\\\\\"ci_95_hi_pp\\\\\\\": 1.5404,\\\\n      \\\\\\\"p_value\\\\\\\": 0.0,\\\\n      \\\\\\\"significant_005\\\\\\\": true\\\\n    },\\\\n    \\\\\\\"SJ\\\\\\\": {\\\\n      \\\\\\\"mean_delta_pp\\\\\\\": -6.2407,\\\\n      \\\\\\\"ci_95_lo_pp\\\\\\\": -6.5422,\\\\n      \\\\\\\"ci_95_hi_pp\\\\\\\": -5.9548,\\\\n      \\\\\\\"p_value\\\\\\\": 1.0,\\\\n      \\\\\\\"significant_005\\\\\\\": false\\\\n    },\\\\n    \\\\\\\"FK\\\\\\\": {\\\\n      \\\\\\\"mean_delta_pp\\\\\\\": -7.3327,\\\\n      \\\\\\\"ci_95_lo_pp\\\\\\\": -7.6381,\\\\n      \\\\\\\"ci_95_hi_pp\\\\\\\": -7.0294,\\\\n      \\\\\\\"p_value\\\\\\\": 1.0,\\\\n      \\\\\\\"significant_005\\\\\\\": false\\\\n    },\\\\n    \\\\\\\"EM\\\\\\\": {\\\\n      \\\\\\\"mean_delta_pp\\\\\\\": -7.3165,\\\\n      \\\\\\\"ci_95_lo_pp\\\\\\\": -7.6397,\\\\n      \\\\\\\"ci_95_hi_pp\\\\\\\": -7.0079,\\\\n      \\\\\\\"p_value\\\\\\\": 1.0,\\\\n      \\\\\\\"significant_005\\\\\\\": false\\\\n    },\\\\n    \\\\\\\"VC\\\\\\\": {\\\\n      \\\\\\\"mean_delta_pp\\\\\\\": -2.7559,\\\\n      \\\\\\\"ci_95_lo_pp\\\\\\\": -3.0494,\\\\n      \\\\\\\"ci_95_hi_pp\\\\\\\": -2.4546,\\\\n      \\\\\\\"p_value\\\\\\\": 1.0,\\\\n      \\\\\\\"significant_005\\\\\\\": false\\\\n    }\\\\n  },\\\\n  \\\\\\\"dgs\\\\\\\": {\\\\n    \\\\\\\"dgs_f1\\\\\\\": 0.7621,\\\\n    \\\\\\\"dgs_delta_vs_greedy_pp\\\\\\\": 1.4329,\\\\n    \\\\\\\"dgs_delta_vs_lp_pp\\\\\\\": 0.0682,\\\\n    \\\\\\\"dgs_bootstrap_ci_95\\\\\\\": {\\\\n      \\\\\\\"lo_pp\\\\\\\": 1.2608,\\\\n      \\\\\\\"hi_pp\\\\\\\": 1.6063\\\\n    },\\\\n    \\\\\\\"n_degenerate\\\\\\\": 3834,\\\\n    \\\\\\\"n_nondegenerate\\\\\\\": 28731\\\\n  },\\\\n  \\\\\\\"entity_types\\\\\\\": {\\\\n    \\\\\\\"art\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 4064,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.7953,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8757,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.7951,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": -0.0241,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 5.5\\\\n    },\\\\n    \\\\\\\"building\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 5007,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.744,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8485,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.7418,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": -0.2226,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 7.1\\\\n    },\\\\n    \\\\\\\"event\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 4104,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.7123,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8425,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.7158,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": 0.3579,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 8.2\\\\n    },\\\\n    \\\\\\\"location\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 27235,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.8142,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8989,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.8138,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": -0.0419,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 4.0\\\\n    },\\\\n    \\\\\\\"organization\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 19078,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.7595,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8633,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.763,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": 0.3442,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 6.5\\\\n    },\\\\n    \\\\\\\"other\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 9558,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.7082,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8479,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.7336,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": 2.5359,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 13.2\\\\n    },\\\\n    \\\\\\\"person\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 21565,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.8374,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.913,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.8401,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": 0.2785,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 3.6\\\\n    },\\\\n    \\\\\\\"product\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 6231,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.7129,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8402,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.721,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": 0.8158,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 11.4\\\\n    }\\\\n  }\\\\n}\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.36}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"meta\\\": {\\n    \\\"input\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/samples.jsonl\\\",\\n    \\\"n_total\\\": 37648,\\n    \\\"n_filtered\\\": 32565,\\n    \\\"n_samples\\\": 8\\n  },\\n  \\\"basic\\\": {\\n    \\\"greedy_macro_f1\\\": 0.7477603920094339,\\n    \\\"oracle_macro_f1\\\": 0.8714430391776531,\\n    \\\"headroom_pp\\\": 12.368264716821919,\\n    \\\"zero_f1_rate_pct\\\": 4.66451711960694,\\n    \\\"degeneracy_rate_pct\\\": 11.773376324274528,\\n    \\\"lp_range_median\\\": 0.07035905898627522\\n  },\\n  \\\"qe\\\": {\\n    \\\"LP\\\": {\\n      \\\"auroc\\\": 0.5994,\\n      \\\"spearman_global\\\": 0.1788,\\n      \\\"spearman_global_p\\\": 4.5155543415619905e-232,\\n      \\\"spearman_conditional\\\": 0.176,\\n      \\\"spearman_conditional_p\\\": 2.8357968088845245e-198\\n    },\\n    \\\"SJ\\\": {\\n      \\\"auroc\\\": 0.5139,\\n      \\\"spearman_global\\\": 0.253,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.207,\\n      \\\"spearman_conditional_p\\\": 3.378122441777232e-275\\n    },\\n    \\\"FK\\\": {\\n      \\\"auroc\\\": 0.5131,\\n      \\\"spearman_global\\\": 0.1608,\\n      \\\"spearman_global_p\\\": 1.3747764387755347e-187,\\n      \\\"spearman_conditional\\\": 0.02,\\n      \\\"spearman_conditional_p\\\": 0.0006972897086701938\\n    },\\n    \\\"EM\\\": {\\n      \\\"auroc\\\": 0.5033,\\n      \\\"spearman_global\\\": 0.2714,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.4339,\\n      \\\"spearman_conditional_p\\\": 0.0\\n    },\\n    \\\"VC\\\": {\\n      \\\"auroc\\\": 0.5392,\\n      \\\"spearman_global\\\": 0.2673,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.0476,\\n      \\\"spearman_conditional_p\\\": 6.76361927743609e-16\\n    }\\n  },\\n  \\\"selection\\\": {\\n    \\\"LP\\\": {\\n      \\\"f1\\\": 0.7614,\\n      \\\"delta_pp\\\": 1.3647\\n    },\\n    \\\"SJ\\\": {\\n      \\\"f1\\\": 0.6854,\\n      \\\"delta_pp\\\": -6.2399\\n    },\\n    \\\"FK\\\": {\\n      \\\"f1\\\": 0.6745,\\n      \\\"delta_pp\\\": -7.3269\\n    },\\n    \\\"EM\\\": {\\n      \\\"f1\\\": 0.6745,\\n      \\\"delta_pp\\\": -7.3269\\n    },\\n    \\\"VC\\\": {\\n      \\\"f1\\\": 0.7202,\\n      \\\"delta_pp\\\": -2.753\\n    }\\n  },\\n  \\\"bootstrap\\\": {\\n    \\\"LP\\\": {\\n      \\\"mean_delta_pp\\\": 1.3655,\\n      \\\"ci_95_lo_pp\\\": 1.1874,\\n      \\\"ci_95_hi_pp\\\": 1.5404,\\n      \\\"p_value\\\": 0.0,\\n      \\\"significant_005\\\": true\\n    },\\n    \\\"SJ\\\": {\\n      \\\"mean_delta_pp\\\": -6.2407,\\n      \\\"ci_95_lo_pp\\\": -6.5422,\\n      \\\"ci_95_hi_pp\\\": -5.9548,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"FK\\\": {\\n      \\\"mean_delta_pp\\\": -7.3327,\\n      \\\"ci_95_lo_pp\\\": -7.6381,\\n      \\\"ci_95_hi_pp\\\": -7.0294,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"EM\\\": {\\n      \\\"mean_delta_pp\\\": -7.3165,\\n      \\\"ci_95_lo_pp\\\": -7.6397,\\n      \\\"ci_95_hi_pp\\\": -7.0079,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"VC\\\": {\\n      \\\"mean_delta_pp\\\": -2.7559,\\n      \\\"ci_95_lo_pp\\\": -3.0494,\\n      \\\"ci_95_hi_pp\\\": -2.4546,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    }\\n  },\\n  \\\"dgs\\\": {\\n    \\\"dgs_f1\\\": 0.7621,\\n    \\\"dgs_delta_vs_greedy_pp\\\": 1.4329,\\n    \\\"dgs_delta_vs_lp_pp\\\": 0.0682,\\n    \\\"dgs_bootstrap_ci_95\\\": {\\n      \\\"lo_pp\\\": 1.2608,\\n      \\\"hi_pp\\\": 1.6063\\n    },\\n    \\\"n_degenerate\\\": 3834,\\n    \\\"n_nondegenerate\\\": 28731\\n  },\\n  \\\"entity_types\\\": {\\n    \\\"art\\\": {\\n      \\\"count\\\": 4064,\\n      \\\"greedy_f1\\\": 0.7953,\\n      \\\"oracle_f1\\\": 0.8757,\\n      \\\"lp_selection_f1\\\": 0.7951,\\n      \\\"lp_delta_pp\\\": -0.0241,\\n      \\\"zero_f1_rate\\\": 5.5\\n    },\\n    \\\"building\\\": {\\n      \\\"count\\\": 5007,\\n      \\\"greedy_f1\\\": 0.744,\\n      \\\"oracle_f1\\\": 0.8485,\\n      \\\"lp_selection_f1\\\": 0.7418,\\n      \\\"lp_delta_pp\\\": -0.2226,\\n      \\\"zero_f1_rate\\\": 7.1\\n    },\\n    \\\"event\\\": {\\n      \\\"count\\\": 4104,\\n      \\\"greedy_f1\\\": 0.7123,\\n      \\\"oracle_f1\\\": 0.8425,\\n      \\\"lp_selection_f1\\\": 0.7158,\\n      \\\"lp_delta_pp\\\": 0.3579,\\n      \\\"zero_f1_rate\\\": 8.2\\n    },\\n    \\\"location\\\": {\\n      \\\"count\\\": 27235,\\n      \\\"greedy_f1\\\": 0.8142,\\n      \\\"oracle_f1\\\": 0.8989,\\n      \\\"lp_selection_f1\\\": 0.8138,\\n      \\\"lp_delta_pp\\\": -0.0419,\\n      \\\"zero_f1_rate\\\": 4.0\\n    },\\n    \\\"organization\\\": {\\n      \\\"count\\\": 19078,\\n      \\\"greedy_f1\\\": 0.7595,\\n      \\\"oracle_f1\\\": 0.8633,\\n      \\\"lp_selection_f1\\\": 0.763,\\n      \\\"lp_delta_pp\\\": 0.3442,\\n      \\\"zero_f1_rate\\\": 6.5\\n    },\\n    \\\"other\\\": {\\n      \\\"count\\\": 9558,\\n      \\\"greedy_f1\\\": 0.7082,\\n      \\\"oracle_f1\\\": 0.8479,\\n      \\\"lp_selection_f1\\\": 0.7336,\\n      \\\"lp_delta_pp\\\": 2.5359,\\n      \\\"zero_f1_rate\\\": 13.2\\n    },\\n    \\\"person\\\": {\\n      \\\"count\\\": 21565,\\n      \\\"greedy_f1\\\": 0.8374,\\n      \\\"oracle_f1\\\": 0.913,\\n      \\\"lp_selection_f1\\\": 0.8401,\\n      \\\"lp_delta_pp\\\": 0.2785,\\n      \\\"zero_f1_rate\\\": 3.6\\n    },\\n    \\\"product\\\": {\\n      \\\"count\\\": 6231,\\n      \\\"greedy_f1\\\": 0.7129,\\n      \\\"oracle_f1\\\": 0.8402,\\n      \\\"lp_selection_f1\\\": 0.721,\\n      \\\"lp_delta_pp\\\": 0.8158,\\n      \\\"zero_f1_rate\\\": 11.4\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 59_

<details><summary>Logged reasoning block</summary>

```text
Critical finding! The `fewnerd_seed789_merged/analysis.json` uses `greedy_macro_f1` = 0.7478. This is the **macro** F1, which is the buggy metric. The MF4v2 experiments use `greedy_f1` (micro-F1).

Now I need to find the old experiments that the α_crit table used for seeds 123 and 456. The table says FewNERD seeds (123, 456, 789). But the MF4v2 for FewNERD seeds 42 and 123 are done (greedy_f1 ~ 0.7883), and seed 456 is still PREPARING.


I need to track down where the original seeds 123 and 456 results came from before MF4v2, and also check what's available for CoNLL and SciERC. Let me search through the report and analysis files from the earlier experiments, particularly looking for any mvp_pilot directories that might contain the original T=1.0 baseline data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "87b02620-55d5-429a-a51c-ff9602b487eb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174SqFF5hnkQd1eHWfZpoiD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4068,
      "cache_read_input_tokens": 53866,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4068
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

_source line 60_

确认：`fewnerd_seed789_merged` 使用的是 `greedy_macro_f1` = 0.7478（bug 指标）。现在检查 MF4v2 report.json 和其他数据集。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "5a68ec12-d966-4167-a0cc-b99c85dff791",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174SqFF5hnkQd1eHWfZpoiD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4068,
      "cache_read_input_tokens": 53866,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4068
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

_source line 61_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01LRvFumk5YnBY8TbLMxd5YZ`</summary>

```json
{
  "server": "autodl-5090",
  "command": "cat /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_mf4v2_seed456/report.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "d0d16d82-6949-48d8-924b-e1b33e6ab048",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174SqFF5hnkQd1eHWfZpoiD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4068,
      "cache_read_input_tokens": 53866,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4068
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

_source line 62 · 2026-05-21T09:29:04.743Z_

<details><summary>↩ Tool result · `toolu_01LRvFumk5YnBY8TbLMxd5YZ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"dataset\\\": \\\"fewnerd\\\",\\n  \\\"subtask\\\": \\\"ner\\\",\\n  \\\"n_samples\\\": 8,\\n  \\\"temperature\\\": 1.0,\\n  \\\"num_instances\\\": 37648,\\n  \\\"use_train_format\\\": true,\\n  \\\"greedy_f1\\\": 0.7888970728365621,\\n  \\\"oracle_f1\\\": 0.8809715429538372,\\n  \\\"oracle_headroom\\\": 0.0920744701172751,\\n  \\\"fleiss_kappa_mean\\\": 0.3557137700473044,\\n  \\\"soft_jaccard_mean\\\": 0.6848113505510054,\\n  \\\"correlation_fleiss_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.1646552164681241,\\n    \\\"p_value\\\": 1.1982688972355146e-196,\\n    \\\"n\\\": 32565\\n  },\\n  \\\"correlation_softjaccard_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.3133155084647015,\\n    \\\"p_value\\\": 0.0,\\n    \\\"n\\\": 32565\\n  },\\n  \\\"correlation_fleiss_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.015181956268569231,\\n    \\\"p_value\\\": 0.010092321330700786,\\n    \\\"n\\\": 28714\\n  },\\n  \\\"correlation_softjaccard_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.25732623152478556,\\n    \\\"p_value\\\": 0.0,\\n    \\\"n\\\": 28714\\n  },\\n  \\\"n_gold_empty_filtered\\\": 5083,\\n  \\\"n_greedy_f1_zero_filtered\\\": 3851,\\n  \\\"structural_beats_surface\\\": true,\\n  \\\"rho_advantage\\\": 0.14866029199657743,\\n  \\\"sample_f1_mean\\\": 0.6435392010789137,\\n  \\\"sample_f1_std\\\": 0.37679111462615084,\\n  \\\"sample_f1_pct_zero\\\": 19.304851834791954,\\n  \\\"logprob_baseline\\\": {\\n    \\\"full\\\": {\\n      \\\"rho\\\": 0.24500224425638795,\\n      \\\"p_rho\\\": 0.0,\\n      \\\"tau\\\": 0.1820250730198582,\\n      \\\"p_tau\\\": 0.0,\\n      \\\"auroc\\\": 0.6287085032681137,\\n      \\\"n\\\": 32565\\n    },\\n    \\\"conditional\\\": {\\n      \\\"rho\\\": 0.23748013451187075,\\n      \\\"p_rho\\\": 0.0,\\n      \\\"tau\\\": 0.1780472227595623,\\n      \\\"p_tau\\\": 0.0,\\n      \\\"auroc\\\": 0.6222295654774398,\\n      \\\"n\\\": 28714\\n    }\\n  },\\n  \\\"verdict\\\": \\\"MARGINAL\\\",\\n  \\\"verdict_note\\\": \\\"MVP verdict on single subtask; final pass requires at least one of NER/RE/EAE to meet threshold\\\"\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.43}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "c6025b48-e08b-49ca-a2ba-1ea62bdecedf",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"dataset\\\\\\\": \\\\\\\"fewnerd\\\\\\\",\\\\n  \\\\\\\"subtask\\\\\\\": \\\\\\\"ner\\\\\\\",\\\\n  \\\\\\\"n_samples\\\\\\\": 8,\\\\n  \\\\\\\"temperature\\\\\\\": 1.0,\\\\n  \\\\\\\"num_instances\\\\\\\": 37648,\\\\n  \\\\\\\"use_train_format\\\\\\\": true,\\\\n  \\\\\\\"greedy_f1\\\\\\\": 0.7888970728365621,\\\\n  \\\\\\\"oracle_f1\\\\\\\": 0.8809715429538372,\\\\n  \\\\\\\"oracle_headroom\\\\\\\": 0.0920744701172751,\\\\n  \\\\\\\"fleiss_kappa_mean\\\\\\\": 0.3557137700473044,\\\\n  \\\\\\\"soft_jaccard_mean\\\\\\\": 0.6848113505510054,\\\\n  \\\\\\\"correlation_fleiss_vs_f1_full\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.1646552164681241,\\\\n    \\\\\\\"p_value\\\\\\\": 1.1982688972355146e-196,\\\\n    \\\\\\\"n\\\\\\\": 32565\\\\n  },\\\\n  \\\\\\\"correlation_softjaccard_vs_f1_full\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.3133155084647015,\\\\n    \\\\\\\"p_value\\\\\\\": 0.0,\\\\n    \\\\\\\"n\\\\\\\": 32565\\\\n  },\\\\n  \\\\\\\"correlation_fleiss_vs_f1_conditional\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.015181956268569231,\\\\n    \\\\\\\"p_value\\\\\\\": 0.010092321330700786,\\\\n    \\\\\\\"n\\\\\\\": 28714\\\\n  },\\\\n  \\\\\\\"correlation_softjaccard_vs_f1_conditional\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.25732623152478556,\\\\n    \\\\\\\"p_value\\\\\\\": 0.0,\\\\n    \\\\\\\"n\\\\\\\": 28714\\\\n  },\\\\n  \\\\\\\"n_gold_empty_filtered\\\\\\\": 5083,\\\\n  \\\\\\\"n_greedy_f1_zero_filtered\\\\\\\": 3851,\\\\n  \\\\\\\"structural_beats_surface\\\\\\\": true,\\\\n  \\\\\\\"rho_advantage\\\\\\\": 0.14866029199657743,\\\\n  \\\\\\\"sample_f1_mean\\\\\\\": 0.6435392010789137,\\\\n  \\\\\\\"sample_f1_std\\\\\\\": 0.37679111462615084,\\\\n  \\\\\\\"sample_f1_pct_zero\\\\\\\": 19.304851834791954,\\\\n  \\\\\\\"logprob_baseline\\\\\\\": {\\\\n    \\\\\\\"full\\\\\\\": {\\\\n      \\\\\\\"rho\\\\\\\": 0.24500224425638795,\\\\n      \\\\\\\"p_rho\\\\\\\": 0.0,\\\\n      \\\\\\\"tau\\\\\\\": 0.1820250730198582,\\\\n      \\\\\\\"p_tau\\\\\\\": 0.0,\\\\n      \\\\\\\"auroc\\\\\\\": 0.6287085032681137,\\\\n      \\\\\\\"n\\\\\\\": 32565\\\\n    },\\\\n    \\\\\\\"conditional\\\\\\\": {\\\\n      \\\\\\\"rho\\\\\\\": 0.23748013451187075,\\\\n      \\\\\\\"p_rho\\\\\\\": 0.0,\\\\n      \\\\\\\"tau\\\\\\\": 0.1780472227595623,\\\\n      \\\\\\\"p_tau\\\\\\\": 0.0,\\\\n      \\\\\\\"auroc\\\\\\\": 0.6222295654774398,\\\\n      \\\\\\\"n\\\\\\\": 28714\\\\n    }\\\\n  },\\\\n  \\\\\\\"verdict\\\\\\\": \\\\\\\"MARGINAL\\\\\\\",\\\\n  \\\\\\\"verdict_note\\\\\\\": \\\\\\\"MVP verdict on single subtask; final pass requires at least one of NER/RE/EAE to meet threshold\\\\\\\"\\\\n}\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.43}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"dataset\\\": \\\"fewnerd\\\",\\n  \\\"subtask\\\": \\\"ner\\\",\\n  \\\"n_samples\\\": 8,\\n  \\\"temperature\\\": 1.0,\\n  \\\"num_instances\\\": 37648,\\n  \\\"use_train_format\\\": true,\\n  \\\"greedy_f1\\\": 0.7888970728365621,\\n  \\\"oracle_f1\\\": 0.8809715429538372,\\n  \\\"oracle_headroom\\\": 0.0920744701172751,\\n  \\\"fleiss_kappa_mean\\\": 0.3557137700473044,\\n  \\\"soft_jaccard_mean\\\": 0.6848113505510054,\\n  \\\"correlation_fleiss_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.1646552164681241,\\n    \\\"p_value\\\": 1.1982688972355146e-196,\\n    \\\"n\\\": 32565\\n  },\\n  \\\"correlation_softjaccard_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.3133155084647015,\\n    \\\"p_value\\\": 0.0,\\n    \\\"n\\\": 32565\\n  },\\n  \\\"correlation_fleiss_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.015181956268569231,\\n    \\\"p_value\\\": 0.010092321330700786,\\n    \\\"n\\\": 28714\\n  },\\n  \\\"correlation_softjaccard_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.25732623152478556,\\n    \\\"p_value\\\": 0.0,\\n    \\\"n\\\": 28714\\n  },\\n  \\\"n_gold_empty_filtered\\\": 5083,\\n  \\\"n_greedy_f1_zero_filtered\\\": 3851,\\n  \\\"structural_beats_surface\\\": true,\\n  \\\"rho_advantage\\\": 0.14866029199657743,\\n  \\\"sample_f1_mean\\\": 0.6435392010789137,\\n  \\\"sample_f1_std\\\": 0.37679111462615084,\\n  \\\"sample_f1_pct_zero\\\": 19.304851834791954,\\n  \\\"logprob_baseline\\\": {\\n    \\\"full\\\": {\\n      \\\"rho\\\": 0.24500224425638795,\\n      \\\"p_rho\\\": 0.0,\\n      \\\"tau\\\": 0.1820250730198582,\\n      \\\"p_tau\\\": 0.0,\\n      \\\"auroc\\\": 0.6287085032681137,\\n      \\\"n\\\": 32565\\n    },\\n    \\\"conditional\\\": {\\n      \\\"rho\\\": 0.23748013451187075,\\n      \\\"p_rho\\\": 0.0,\\n      \\\"tau\\\": 0.1780472227595623,\\n      \\\"p_tau\\\": 0.0,\\n      \\\"auroc\\\": 0.6222295654774398,\\n      \\\"n\\\": 28714\\n    }\\n  },\\n  \\\"verdict\\\": \\\"MARGINAL\\\",\\n  \\\"verdict_note\\\": \\\"MVP verdict on single subtask; final pass requires at least one of NER/RE/EAE to meet threshold\\\"\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.43}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 63_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01Sbbrsp9CZ2BHs7jUYPwgsn`</summary>

```json
{
  "server": "autodl-5090",
  "command": "ls /root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "fc66980f-1d6e-4f0b-a3ad-863d5fb9670d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174SqFF5hnkQd1eHWfZpoiD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4068,
      "cache_read_input_tokens": 53866,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4068
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

_source line 64 · 2026-05-21T09:29:06.104Z_

<details><summary>↩ Tool result · `toolu_01Sbbrsp9CZ2BHs7jUYPwgsn`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"e1_component_decomposition.json\\nexp013_exact_match_report.json\\nexp014_entity_voting_report.json\\nreport.json\\nsamples.jsonl\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "81856bf7-0c16-40c1-87af-70b679362700",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"e1_component_decomposition.json\\\\nexp013_exact_match_report.json\\\\nexp014_entity_voting_report.json\\\\nreport.json\\\\nsamples.jsonl\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.35}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"e1_component_decomposition.json\\nexp013_exact_match_report.json\\nexp014_entity_voting_report.json\\nreport.json\\nsamples.jsonl\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 65_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_017taVUVo8wzuhNFPVctCw1Y`</summary>

```json
{
  "server": "autodl-5090",
  "command": "cat /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/full_signal_analysis.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "907d1a5a-5cdd-4b42-9e68-4d9724974e72",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0174SqFF5hnkQd1eHWfZpoiD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4068,
      "cache_read_input_tokens": 53866,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4068
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

_source line 66 · 2026-05-21T09:29:06.576Z_

<details><summary>↩ Tool result · `toolu_017taVUVo8wzuhNFPVctCw1Y`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"meta\\\": {\\n    \\\"input\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/samples.jsonl\\\",\\n    \\\"n_total\\\": 37648,\\n    \\\"n_filtered\\\": 32565,\\n    \\\"n_samples\\\": 8\\n  },\\n  \\\"basic\\\": {\\n    \\\"greedy_macro_f1\\\": 0.7477603920094339,\\n    \\\"oracle_macro_f1\\\": 0.8714430391776531,\\n    \\\"headroom_pp\\\": 12.368264716821919,\\n    \\\"zero_f1_rate_pct\\\": 4.66451711960694,\\n    \\\"degeneracy_rate_pct\\\": 11.773376324274528,\\n    \\\"lp_range_median\\\": 0.07035905898627522\\n  },\\n  \\\"qe\\\": {\\n    \\\"LP\\\": {\\n      \\\"auroc\\\": 0.5994,\\n      \\\"spearman_global\\\": 0.1788,\\n      \\\"spearman_global_p\\\": 4.5155543415619905e-232,\\n      \\\"spearman_conditional\\\": 0.176,\\n      \\\"spearman_conditional_p\\\": 2.8357968088845245e-198\\n    },\\n    \\\"SJ\\\": {\\n      \\\"auroc\\\": 0.5139,\\n      \\\"spearman_global\\\": 0.253,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.207,\\n      \\\"spearman_conditional_p\\\": 3.378122441777232e-275\\n    },\\n    \\\"FK\\\": {\\n      \\\"auroc\\\": 0.5131,\\n      \\\"spearman_global\\\": 0.1608,\\n      \\\"spearman_global_p\\\": 1.3747764387755347e-187,\\n      \\\"spearman_conditional\\\": 0.02,\\n      \\\"spearman_conditional_p\\\": 0.0006972897086701938\\n    },\\n    \\\"EM\\\": {\\n      \\\"auroc\\\": 0.5033,\\n      \\\"spearman_global\\\": 0.2714,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.4339,\\n      \\\"spearman_conditional_p\\\": 0.0\\n    },\\n    \\\"VC\\\": {\\n      \\\"auroc\\\": 0.5392,\\n      \\\"spearman_global\\\": 0.2673,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.0476,\\n      \\\"spearman_conditional_p\\\": 6.76361927743609e-16\\n    }\\n  },\\n  \\\"selection\\\": {\\n    \\\"LP\\\": {\\n      \\\"f1\\\": 0.7614,\\n      \\\"delta_pp\\\": 1.3647\\n    },\\n    \\\"SJ\\\": {\\n      \\\"f1\\\": 0.6854,\\n      \\\"delta_pp\\\": -6.2399\\n    },\\n    \\\"FK\\\": {\\n      \\\"f1\\\": 0.6745,\\n      \\\"delta_pp\\\": -7.3269\\n    },\\n    \\\"EM\\\": {\\n      \\\"f1\\\": 0.6745,\\n      \\\"delta_pp\\\": -7.3269\\n    },\\n    \\\"VC\\\": {\\n      \\\"f1\\\": 0.7202,\\n      \\\"delta_pp\\\": -2.753\\n    }\\n  },\\n  \\\"bootstrap\\\": {\\n    \\\"LP\\\": {\\n      \\\"mean_delta_pp\\\": 1.3655,\\n      \\\"ci_95_lo_pp\\\": 1.1874,\\n      \\\"ci_95_hi_pp\\\": 1.5404,\\n      \\\"p_value\\\": 0.0,\\n      \\\"significant_005\\\": true\\n    },\\n    \\\"SJ\\\": {\\n      \\\"mean_delta_pp\\\": -6.2407,\\n      \\\"ci_95_lo_pp\\\": -6.5422,\\n      \\\"ci_95_hi_pp\\\": -5.9548,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"FK\\\": {\\n      \\\"mean_delta_pp\\\": -7.3327,\\n      \\\"ci_95_lo_pp\\\": -7.6381,\\n      \\\"ci_95_hi_pp\\\": -7.0294,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"EM\\\": {\\n      \\\"mean_delta_pp\\\": -7.3165,\\n      \\\"ci_95_lo_pp\\\": -7.6397,\\n      \\\"ci_95_hi_pp\\\": -7.0079,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"VC\\\": {\\n      \\\"mean_delta_pp\\\": -2.7559,\\n      \\\"ci_95_lo_pp\\\": -3.0494,\\n      \\\"ci_95_hi_pp\\\": -2.4546,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    }\\n  },\\n  \\\"dgs\\\": {\\n    \\\"dgs_f1\\\": 0.7621,\\n    \\\"dgs_delta_vs_greedy_pp\\\": 1.4329,\\n    \\\"dgs_delta_vs_lp_pp\\\": 0.0682,\\n    \\\"dgs_bootstrap_ci_95\\\": {\\n      \\\"lo_pp\\\": 1.2608,\\n      \\\"hi_pp\\\": 1.6063\\n    },\\n    \\\"n_degenerate\\\": 3834,\\n    \\\"n_nondegenerate\\\": 28731\\n  },\\n  \\\"entity_types\\\": {\\n    \\\"art\\\": {\\n      \\\"count\\\": 4064,\\n      \\\"greedy_f1\\\": 0.7953,\\n      \\\"oracle_f1\\\": 0.8757,\\n      \\\"lp_selection_f1\\\": 0.7951,\\n      \\\"lp_delta_pp\\\": -0.0241,\\n      \\\"zero_f1_rate\\\": 5.5\\n    },\\n    \\\"building\\\": {\\n      \\\"count\\\": 5007,\\n      \\\"greedy_f1\\\": 0.744,\\n      \\\"oracle_f1\\\": 0.8485,\\n      \\\"lp_selection_f1\\\": 0.7418,\\n      \\\"lp_delta_pp\\\": -0.2226,\\n      \\\"zero_f1_rate\\\": 7.1\\n    },\\n    \\\"event\\\": {\\n      \\\"count\\\": 4104,\\n      \\\"greedy_f1\\\": 0.7123,\\n      \\\"oracle_f1\\\": 0.8425,\\n      \\\"lp_selection_f1\\\": 0.7158,\\n      \\\"lp_delta_pp\\\": 0.3579,\\n      \\\"zero_f1_rate\\\": 8.2\\n    },\\n    \\\"location\\\": {\\n      \\\"count\\\": 27235,\\n      \\\"greedy_f1\\\": 0.8142,\\n      \\\"oracle_f1\\\": 0.8989,\\n      \\\"lp_selection_f1\\\": 0.8138,\\n      \\\"lp_delta_pp\\\": -0.0419,\\n      \\\"zero_f1_rate\\\": 4.0\\n    },\\n    \\\"organization\\\": {\\n      \\\"count\\\": 19078,\\n      \\\"greedy_f1\\\": 0.7595,\\n      \\\"oracle_f1\\\": 0.8633,\\n      \\\"lp_selection_f1\\\": 0.763,\\n      \\\"lp_delta_pp\\\": 0.3442,\\n      \\\"zero_f1_rate\\\": 6.5\\n    },\\n    \\\"other\\\": {\\n      \\\"count\\\": 9558,\\n      \\\"greedy_f1\\\": 0.7082,\\n      \\\"oracle_f1\\\": 0.8479,\\n      \\\"lp_selection_f1\\\": 0.7336,\\n      \\\"lp_delta_pp\\\": 2.5359,\\n      \\\"zero_f1_rate\\\": 13.2\\n    },\\n    \\\"person\\\": {\\n      \\\"count\\\": 21565,\\n      \\\"greedy_f1\\\": 0.8374,\\n      \\\"oracle_f1\\\": 0.913,\\n      \\\"lp_selection_f1\\\": 0.8401,\\n      \\\"lp_delta_pp\\\": 0.2785,\\n      \\\"zero_f1_rate\\\": 3.6\\n    },\\n    \\\"product\\\": {\\n      \\\"count\\\": 6231,\\n      \\\"greedy_f1\\\": 0.7129,\\n      \\\"oracle_f1\\\": 0.8402,\\n      \\\"lp_selection_f1\\\": 0.721,\\n      \\\"lp_delta_pp\\\": 0.8158,\\n      \\\"zero_f1_rate\\\": 11.4\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "dfc9a396-9a3a-4416-b0a1-1fcb6965d310",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"meta\\\\\\\": {\\\\n    \\\\\\\"input\\\\\\\": \\\\\\\"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/samples.jsonl\\\\\\\",\\\\n    \\\\\\\"n_total\\\\\\\": 37648,\\\\n    \\\\\\\"n_filtered\\\\\\\": 32565,\\\\n    \\\\\\\"n_samples\\\\\\\": 8\\\\n  },\\\\n  \\\\\\\"basic\\\\\\\": {\\\\n    \\\\\\\"greedy_macro_f1\\\\\\\": 0.7477603920094339,\\\\n    \\\\\\\"oracle_macro_f1\\\\\\\": 0.8714430391776531,\\\\n    \\\\\\\"headroom_pp\\\\\\\": 12.368264716821919,\\\\n    \\\\\\\"zero_f1_rate_pct\\\\\\\": 4.66451711960694,\\\\n    \\\\\\\"degeneracy_rate_pct\\\\\\\": 11.773376324274528,\\\\n    \\\\\\\"lp_range_median\\\\\\\": 0.07035905898627522\\\\n  },\\\\n  \\\\\\\"qe\\\\\\\": {\\\\n    \\\\\\\"LP\\\\\\\": {\\\\n      \\\\\\\"auroc\\\\\\\": 0.5994,\\\\n      \\\\\\\"spearman_global\\\\\\\": 0.1788,\\\\n      \\\\\\\"spearman_global_p\\\\\\\": 4.5155543415619905e-232,\\\\n      \\\\\\\"spearman_conditional\\\\\\\": 0.176,\\\\n      \\\\\\\"spearman_conditional_p\\\\\\\": 2.8357968088845245e-198\\\\n    },\\\\n    \\\\\\\"SJ\\\\\\\": {\\\\n      \\\\\\\"auroc\\\\\\\": 0.5139,\\\\n      \\\\\\\"spearman_global\\\\\\\": 0.253,\\\\n      \\\\\\\"spearman_global_p\\\\\\\": 0.0,\\\\n      \\\\\\\"spearman_conditional\\\\\\\": 0.207,\\\\n      \\\\\\\"spearman_conditional_p\\\\\\\": 3.378122441777232e-275\\\\n    },\\\\n    \\\\\\\"FK\\\\\\\": {\\\\n      \\\\\\\"auroc\\\\\\\": 0.5131,\\\\n      \\\\\\\"spearman_global\\\\\\\": 0.1608,\\\\n      \\\\\\\"spearman_global_p\\\\\\\": 1.3747764387755347e-187,\\\\n      \\\\\\\"spearman_conditional\\\\\\\": 0.02,\\\\n      \\\\\\\"spearman_conditional_p\\\\\\\": 0.0006972897086701938\\\\n    },\\\\n    \\\\\\\"EM\\\\\\\": {\\\\n      \\\\\\\"auroc\\\\\\\": 0.5033,\\\\n      \\\\\\\"spearman_global\\\\\\\": 0.2714,\\\\n      \\\\\\\"spearman_global_p\\\\\\\": 0.0,\\\\n      \\\\\\\"spearman_conditional\\\\\\\": 0.4339,\\\\n      \\\\\\\"spearman_conditional_p\\\\\\\": 0.0\\\\n    },\\\\n    \\\\\\\"VC\\\\\\\": {\\\\n      \\\\\\\"auroc\\\\\\\": 0.5392,\\\\n      \\\\\\\"spearman_global\\\\\\\": 0.2673,\\\\n      \\\\\\\"spearman_global_p\\\\\\\": 0.0,\\\\n      \\\\\\\"spearman_conditional\\\\\\\": 0.0476,\\\\n      \\\\\\\"spearman_conditional_p\\\\\\\": 6.76361927743609e-16\\\\n    }\\\\n  },\\\\n  \\\\\\\"selection\\\\\\\": {\\\\n    \\\\\\\"LP\\\\\\\": {\\\\n      \\\\\\\"f1\\\\\\\": 0.7614,\\\\n      \\\\\\\"delta_pp\\\\\\\": 1.3647\\\\n    },\\\\n    \\\\\\\"SJ\\\\\\\": {\\\\n      \\\\\\\"f1\\\\\\\": 0.6854,\\\\n      \\\\\\\"delta_pp\\\\\\\": -6.2399\\\\n    },\\\\n    \\\\\\\"FK\\\\\\\": {\\\\n      \\\\\\\"f1\\\\\\\": 0.6745,\\\\n      \\\\\\\"delta_pp\\\\\\\": -7.3269\\\\n    },\\\\n    \\\\\\\"EM\\\\\\\": {\\\\n      \\\\\\\"f1\\\\\\\": 0.6745,\\\\n      \\\\\\\"delta_pp\\\\\\\": -7.3269\\\\n    },\\\\n    \\\\\\\"VC\\\\\\\": {\\\\n      \\\\\\\"f1\\\\\\\": 0.7202,\\\\n      \\\\\\\"delta_pp\\\\\\\": -2.753\\\\n    }\\\\n  },\\\\n  \\\\\\\"bootstrap\\\\\\\": {\\\\n    \\\\\\\"LP\\\\\\\": {\\\\n      \\\\\\\"mean_delta_pp\\\\\\\": 1.3655,\\\\n      \\\\\\\"ci_95_lo_pp\\\\\\\": 1.1874,\\\\n      \\\\\\\"ci_95_hi_pp\\\\\\\": 1.5404,\\\\n      \\\\\\\"p_value\\\\\\\": 0.0,\\\\n      \\\\\\\"significant_005\\\\\\\": true\\\\n    },\\\\n    \\\\\\\"SJ\\\\\\\": {\\\\n      \\\\\\\"mean_delta_pp\\\\\\\": -6.2407,\\\\n      \\\\\\\"ci_95_lo_pp\\\\\\\": -6.5422,\\\\n      \\\\\\\"ci_95_hi_pp\\\\\\\": -5.9548,\\\\n      \\\\\\\"p_value\\\\\\\": 1.0,\\\\n      \\\\\\\"significant_005\\\\\\\": false\\\\n    },\\\\n    \\\\\\\"FK\\\\\\\": {\\\\n      \\\\\\\"mean_delta_pp\\\\\\\": -7.3327,\\\\n      \\\\\\\"ci_95_lo_pp\\\\\\\": -7.6381,\\\\n      \\\\\\\"ci_95_hi_pp\\\\\\\": -7.0294,\\\\n      \\\\\\\"p_value\\\\\\\": 1.0,\\\\n      \\\\\\\"significant_005\\\\\\\": false\\\\n    },\\\\n    \\\\\\\"EM\\\\\\\": {\\\\n      \\\\\\\"mean_delta_pp\\\\\\\": -7.3165,\\\\n      \\\\\\\"ci_95_lo_pp\\\\\\\": -7.6397,\\\\n      \\\\\\\"ci_95_hi_pp\\\\\\\": -7.0079,\\\\n      \\\\\\\"p_value\\\\\\\": 1.0,\\\\n      \\\\\\\"significant_005\\\\\\\": false\\\\n    },\\\\n    \\\\\\\"VC\\\\\\\": {\\\\n      \\\\\\\"mean_delta_pp\\\\\\\": -2.7559,\\\\n      \\\\\\\"ci_95_lo_pp\\\\\\\": -3.0494,\\\\n      \\\\\\\"ci_95_hi_pp\\\\\\\": -2.4546,\\\\n      \\\\\\\"p_value\\\\\\\": 1.0,\\\\n      \\\\\\\"significant_005\\\\\\\": false\\\\n    }\\\\n  },\\\\n  \\\\\\\"dgs\\\\\\\": {\\\\n    \\\\\\\"dgs_f1\\\\\\\": 0.7621,\\\\n    \\\\\\\"dgs_delta_vs_greedy_pp\\\\\\\": 1.4329,\\\\n    \\\\\\\"dgs_delta_vs_lp_pp\\\\\\\": 0.0682,\\\\n    \\\\\\\"dgs_bootstrap_ci_95\\\\\\\": {\\\\n      \\\\\\\"lo_pp\\\\\\\": 1.2608,\\\\n      \\\\\\\"hi_pp\\\\\\\": 1.6063\\\\n    },\\\\n    \\\\\\\"n_degenerate\\\\\\\": 3834,\\\\n    \\\\\\\"n_nondegenerate\\\\\\\": 28731\\\\n  },\\\\n  \\\\\\\"entity_types\\\\\\\": {\\\\n    \\\\\\\"art\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 4064,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.7953,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8757,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.7951,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": -0.0241,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 5.5\\\\n    },\\\\n    \\\\\\\"building\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 5007,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.744,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8485,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.7418,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": -0.2226,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 7.1\\\\n    },\\\\n    \\\\\\\"event\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 4104,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.7123,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8425,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.7158,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": 0.3579,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 8.2\\\\n    },\\\\n    \\\\\\\"location\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 27235,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.8142,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8989,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.8138,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": -0.0419,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 4.0\\\\n    },\\\\n    \\\\\\\"organization\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 19078,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.7595,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8633,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.763,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": 0.3442,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 6.5\\\\n    },\\\\n    \\\\\\\"other\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 9558,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.7082,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8479,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.7336,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": 2.5359,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 13.2\\\\n    },\\\\n    \\\\\\\"person\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 21565,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.8374,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.913,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.8401,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": 0.2785,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 3.6\\\\n    },\\\\n    \\\\\\\"product\\\\\\\": {\\\\n      \\\\\\\"count\\\\\\\": 6231,\\\\n      \\\\\\\"greedy_f1\\\\\\\": 0.7129,\\\\n      \\\\\\\"oracle_f1\\\\\\\": 0.8402,\\\\n      \\\\\\\"lp_selection_f1\\\\\\\": 0.721,\\\\n      \\\\\\\"lp_delta_pp\\\\\\\": 0.8158,\\\\n      \\\\\\\"zero_f1_rate\\\\\\\": 11.4\\\\n    }\\\\n  }\\\\n}\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.36}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"meta\\\": {\\n    \\\"input\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/samples.jsonl\\\",\\n    \\\"n_total\\\": 37648,\\n    \\\"n_filtered\\\": 32565,\\n    \\\"n_samples\\\": 8\\n  },\\n  \\\"basic\\\": {\\n    \\\"greedy_macro_f1\\\": 0.7477603920094339,\\n    \\\"oracle_macro_f1\\\": 0.8714430391776531,\\n    \\\"headroom_pp\\\": 12.368264716821919,\\n    \\\"zero_f1_rate_pct\\\": 4.66451711960694,\\n    \\\"degeneracy_rate_pct\\\": 11.773376324274528,\\n    \\\"lp_range_median\\\": 0.07035905898627522\\n  },\\n  \\\"qe\\\": {\\n    \\\"LP\\\": {\\n      \\\"auroc\\\": 0.5994,\\n      \\\"spearman_global\\\": 0.1788,\\n      \\\"spearman_global_p\\\": 4.5155543415619905e-232,\\n      \\\"spearman_conditional\\\": 0.176,\\n      \\\"spearman_conditional_p\\\": 2.8357968088845245e-198\\n    },\\n    \\\"SJ\\\": {\\n      \\\"auroc\\\": 0.5139,\\n      \\\"spearman_global\\\": 0.253,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.207,\\n      \\\"spearman_conditional_p\\\": 3.378122441777232e-275\\n    },\\n    \\\"FK\\\": {\\n      \\\"auroc\\\": 0.5131,\\n      \\\"spearman_global\\\": 0.1608,\\n      \\\"spearman_global_p\\\": 1.3747764387755347e-187,\\n      \\\"spearman_conditional\\\": 0.02,\\n      \\\"spearman_conditional_p\\\": 0.0006972897086701938\\n    },\\n    \\\"EM\\\": {\\n      \\\"auroc\\\": 0.5033,\\n      \\\"spearman_global\\\": 0.2714,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.4339,\\n      \\\"spearman_conditional_p\\\": 0.0\\n    },\\n    \\\"VC\\\": {\\n      \\\"auroc\\\": 0.5392,\\n      \\\"spearman_global\\\": 0.2673,\\n      \\\"spearman_global_p\\\": 0.0,\\n      \\\"spearman_conditional\\\": 0.0476,\\n      \\\"spearman_conditional_p\\\": 6.76361927743609e-16\\n    }\\n  },\\n  \\\"selection\\\": {\\n    \\\"LP\\\": {\\n      \\\"f1\\\": 0.7614,\\n      \\\"delta_pp\\\": 1.3647\\n    },\\n    \\\"SJ\\\": {\\n      \\\"f1\\\": 0.6854,\\n      \\\"delta_pp\\\": -6.2399\\n    },\\n    \\\"FK\\\": {\\n      \\\"f1\\\": 0.6745,\\n      \\\"delta_pp\\\": -7.3269\\n    },\\n    \\\"EM\\\": {\\n      \\\"f1\\\": 0.6745,\\n      \\\"delta_pp\\\": -7.3269\\n    },\\n    \\\"VC\\\": {\\n      \\\"f1\\\": 0.7202,\\n      \\\"delta_pp\\\": -2.753\\n    }\\n  },\\n  \\\"bootstrap\\\": {\\n    \\\"LP\\\": {\\n      \\\"mean_delta_pp\\\": 1.3655,\\n      \\\"ci_95_lo_pp\\\": 1.1874,\\n      \\\"ci_95_hi_pp\\\": 1.5404,\\n      \\\"p_value\\\": 0.0,\\n      \\\"significant_005\\\": true\\n    },\\n    \\\"SJ\\\": {\\n      \\\"mean_delta_pp\\\": -6.2407,\\n      \\\"ci_95_lo_pp\\\": -6.5422,\\n      \\\"ci_95_hi_pp\\\": -5.9548,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"FK\\\": {\\n      \\\"mean_delta_pp\\\": -7.3327,\\n      \\\"ci_95_lo_pp\\\": -7.6381,\\n      \\\"ci_95_hi_pp\\\": -7.0294,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"EM\\\": {\\n      \\\"mean_delta_pp\\\": -7.3165,\\n      \\\"ci_95_lo_pp\\\": -7.6397,\\n      \\\"ci_95_hi_pp\\\": -7.0079,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    },\\n    \\\"VC\\\": {\\n      \\\"mean_delta_pp\\\": -2.7559,\\n      \\\"ci_95_lo_pp\\\": -3.0494,\\n      \\\"ci_95_hi_pp\\\": -2.4546,\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant_005\\\": false\\n    }\\n  },\\n  \\\"dgs\\\": {\\n    \\\"dgs_f1\\\": 0.7621,\\n    \\\"dgs_delta_vs_greedy_pp\\\": 1.4329,\\n    \\\"dgs_delta_vs_lp_pp\\\": 0.0682,\\n    \\\"dgs_bootstrap_ci_95\\\": {\\n      \\\"lo_pp\\\": 1.2608,\\n      \\\"hi_pp\\\": 1.6063\\n    },\\n    \\\"n_degenerate\\\": 3834,\\n    \\\"n_nondegenerate\\\": 28731\\n  },\\n  \\\"entity_types\\\": {\\n    \\\"art\\\": {\\n      \\\"count\\\": 4064,\\n      \\\"greedy_f1\\\": 0.7953,\\n      \\\"oracle_f1\\\": 0.8757,\\n      \\\"lp_selection_f1\\\": 0.7951,\\n      \\\"lp_delta_pp\\\": -0.0241,\\n      \\\"zero_f1_rate\\\": 5.5\\n    },\\n    \\\"building\\\": {\\n      \\\"count\\\": 5007,\\n      \\\"greedy_f1\\\": 0.744,\\n      \\\"oracle_f1\\\": 0.8485,\\n      \\\"lp_selection_f1\\\": 0.7418,\\n      \\\"lp_delta_pp\\\": -0.2226,\\n      \\\"zero_f1_rate\\\": 7.1\\n    },\\n    \\\"event\\\": {\\n      \\\"count\\\": 4104,\\n      \\\"greedy_f1\\\": 0.7123,\\n      \\\"oracle_f1\\\": 0.8425,\\n      \\\"lp_selection_f1\\\": 0.7158,\\n      \\\"lp_delta_pp\\\": 0.3579,\\n      \\\"zero_f1_rate\\\": 8.2\\n    },\\n    \\\"location\\\": {\\n      \\\"count\\\": 27235,\\n      \\\"greedy_f1\\\": 0.8142,\\n      \\\"oracle_f1\\\": 0.8989,\\n      \\\"lp_selection_f1\\\": 0.8138,\\n      \\\"lp_delta_pp\\\": -0.0419,\\n      \\\"zero_f1_rate\\\": 4.0\\n    },\\n    \\\"organization\\\": {\\n      \\\"count\\\": 19078,\\n      \\\"greedy_f1\\\": 0.7595,\\n      \\\"oracle_f1\\\": 0.8633,\\n      \\\"lp_selection_f1\\\": 0.763,\\n      \\\"lp_delta_pp\\\": 0.3442,\\n      \\\"zero_f1_rate\\\": 6.5\\n    },\\n    \\\"other\\\": {\\n      \\\"count\\\": 9558,\\n      \\\"greedy_f1\\\": 0.7082,\\n      \\\"oracle_f1\\\": 0.8479,\\n      \\\"lp_selection_f1\\\": 0.7336,\\n      \\\"lp_delta_pp\\\": 2.5359,\\n      \\\"zero_f1_rate\\\": 13.2\\n    },\\n    \\\"person\\\": {\\n      \\\"count\\\": 21565,\\n      \\\"greedy_f1\\\": 0.8374,\\n      \\\"oracle_f1\\\": 0.913,\\n      \\\"lp_selection_f1\\\": 0.8401,\\n      \\\"lp_delta_pp\\\": 0.2785,\\n      \\\"zero_f1_rate\\\": 3.6\\n    },\\n    \\\"product\\\": {\\n      \\\"count\\\": 6231,\\n      \\\"greedy_f1\\\": 0.7129,\\n      \\\"oracle_f1\\\": 0.8402,\\n      \\\"lp_selection_f1\\\": 0.721,\\n      \\\"lp_delta_pp\\\": 0.8158,\\n      \\\"zero_f1_rate\\\": 11.4\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 67_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture for FewNERD:

**fewnerd_seed789_merged** (old pipeline):
- `greedy_macro_f1` = 0.7478 ← THIS IS THE BUGGY METRIC
- No `greedy_f1` (micro-F1) field at all

**fewnerd_mf4v2_seed456** (new pipeline):
- report.json exists with `greedy_f1` = 0.7889 (from the report.json)

Wait, let me re-read that. The fewnerd_mf4v2_seed456/report.json actually shows:


greedy_f1: 0.7888970728365621

That's the report.json content I read. Let me re-check - the `fewnerd_mf4v2_seed456/report.json` was the second read, and it shows greedy_f1 = 0.7889.

Now, for the α_crit table:
- FewNERD Greedy = 0.7482 (average of seeds 123, 456, 789)
- The only data source I can see is fewnerd_seed789_merged which has greedy_macro_f1 = 0.7478

But wait, the table...

I'm noticing a discrepancy - the table claims to average three seeds (123, 456, 789), but the old experiment directories for seeds 123 and 456 are all empty with no JSON files. The seed 789 data shows greedy_macro_f1 = 0.7478, which matches the FewNERD greedy value of 0.7482 in the table, so I'm trying to figure out where the data for seeds 123 and 456 actually came from. I'm noticing a discrepancy in the experiment IDs in the registry—some have underscores in different positions like `exp_fewnerd_mf4_v2_s42` versus `exp_fewnerd_mf4v2_s42`, and they show different statuses, so I need to carefully match which experiments are actually complete versus still preparing. I'm checking the actual content of that report.json file to understand what experiment it belongs to. The greedy_f1 value of 0.7889 matches the temperature ablation runs rather than the MF4v2 results, so this report might be from a different experiment than what the directory name suggests.

Since greedy decoding shouldn't be affected by temperature settings, the slight difference between 0.7889 and 0.7883 is likely due to variations in data filtering. Now I need to trace back where the α_crit table actually comes from by checking the report files across CoNLL, SciERC, and other datasets in both the old and new pipeline versions.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "7f4135ac-1b70-43b5-a00c-cd2693f22e4d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RXhNGBej7taj4taa1yAL1Z",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5043,
      "cache_read_input_tokens": 57934,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5043
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

现在检查 CoNLL 和 SciERC 的数据，以及旧 pipeline 的 mvp_pilot 数据。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "742f8497-84da-4419-860a-d11cf2f8462a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RXhNGBej7taj4taa1yAL1Z",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5043,
      "cache_read_input_tokens": 57934,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5043
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01FKWckecnXsEeEBi3xZtWkz`</summary>

```json
{
  "server": "autodl-5090",
  "command": "cat /root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/report.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "e69a77b4-ea46-4422-a304-99ee81fe55b1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RXhNGBej7taj4taa1yAL1Z",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5043,
      "cache_read_input_tokens": 57934,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5043
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

_source line 70 · 2026-05-21T09:29:39.486Z_

<details><summary>↩ Tool result · `toolu_01FKWckecnXsEeEBi3xZtWkz`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"dataset\\\": \\\"scierc\\\",\\n  \\\"subtask\\\": \\\"joint\\\",\\n  \\\"n_samples\\\": 8,\\n  \\\"temperature\\\": 1.0,\\n  \\\"num_instances\\\": 551,\\n  \\\"use_train_format\\\": true,\\n  \\\"ner_greedy_f1\\\": 0.6670644391408114,\\n  \\\"ner_oracle_f1\\\": 0.7755707085680403,\\n  \\\"ner_oracle_headroom\\\": 0.10850626942722896,\\n  \\\"ner_fleiss_kappa_mean\\\": 0.404833077782123,\\n  \\\"ner_soft_jaccard_mean\\\": 0.7007668853280039,\\n  \\\"ner_correlation_fleiss_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.2590287670611875,\\n    \\\"p_value\\\": 1.4749617362002596e-09,\\n    \\\"n\\\": 529\\n  },\\n  \\\"ner_correlation_softjaccard_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.3825183376668469,\\n    \\\"p_value\\\": 7.075136887733191e-20,\\n    \\\"n\\\": 529\\n  },\\n  \\\"ner_correlation_fleiss_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.23519998074107282,\\n    \\\"p_value\\\": 8.162404147668711e-08,\\n    \\\"n\\\": 508\\n  },\\n  \\\"ner_correlation_softjaccard_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.3761747231572503,\\n    \\\"p_value\\\": 1.6016428996438062e-18,\\n    \\\"n\\\": 508\\n  },\\n  \\\"ner_n_gold_empty_filtered\\\": 22,\\n  \\\"ner_n_all_samples_f1_zero_filtered\\\": 21,\\n  \\\"ner_structural_beats_surface\\\": true,\\n  \\\"ner_rho_advantage\\\": 0.1234895706056594,\\n  \\\"ner_sample_f1_mean\\\": 0.6083957210996992,\\n  \\\"ner_sample_f1_std\\\": 0.3173545540187574,\\n  \\\"ner_sample_f1_pct_zero\\\": 12.19281663516068,\\n  \\\"re_greedy_f1\\\": 0.4207896051974013,\\n  \\\"re_oracle_f1\\\": 0.5882352941176471,\\n  \\\"re_oracle_headroom\\\": 0.1674456889202458,\\n  \\\"re_fleiss_kappa_mean\\\": 0.2996385624366326,\\n  \\\"re_soft_jaccard_mean\\\": 0.6113509598733148,\\n  \\\"re_correlation_fleiss_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.2782151188817765,\\n    \\\"p_value\\\": 1.7243205365720716e-08,\\n    \\\"n\\\": 397\\n  },\\n  \\\"re_correlation_softjaccard_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.2440702831280834,\\n    \\\"p_value\\\": 8.550224511243979e-07,\\n    \\\"n\\\": 397\\n  },\\n  \\\"re_correlation_fleiss_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.3067010369107279,\\n    \\\"p_value\\\": 3.051941342129941e-08,\\n    \\\"n\\\": 313\\n  },\\n  \\\"re_correlation_softjaccard_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.31612432525905776,\\n    \\\"p_value\\\": 1.0795971808906936e-08,\\n    \\\"n\\\": 313\\n  },\\n  \\\"re_n_gold_empty_filtered\\\": 154,\\n  \\\"re_n_all_samples_f1_zero_filtered\\\": 84,\\n  \\\"re_structural_beats_surface\\\": false,\\n  \\\"re_rho_advantage\\\": -0.03414483575369312,\\n  \\\"re_sample_f1_mean\\\": 0.36116953342051505,\\n  \\\"re_sample_f1_std\\\": 0.3830344166083389,\\n  \\\"re_sample_f1_pct_zero\\\": 44.30100755667506,\\n  \\\"verdict\\\": \\\"FAIL\\\",\\n  \\\"verdict_note\\\": \\\"Joint mode: verdict requires RE rho_sj >= 0.40 AND rho_sj > rho_fk AND any subtask headroom >= 2pp\\\",\\n  \\\"warning\\\": \\\"WARNING: >30% samples F1=0, recommend re-running at T=0.7\\\"\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "eadf1fe7-a72a-4936-8a6d-082fdc07ef3a",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"dataset\\\\\\\": \\\\\\\"scierc\\\\\\\",\\\\n  \\\\\\\"subtask\\\\\\\": \\\\\\\"joint\\\\\\\",\\\\n  \\\\\\\"n_samples\\\\\\\": 8,\\\\n  \\\\\\\"temperature\\\\\\\": 1.0,\\\\n  \\\\\\\"num_instances\\\\\\\": 551,\\\\n  \\\\\\\"use_train_format\\\\\\\": true,\\\\n  \\\\\\\"ner_greedy_f1\\\\\\\": 0.6670644391408114,\\\\n  \\\\\\\"ner_oracle_f1\\\\\\\": 0.7755707085680403,\\\\n  \\\\\\\"ner_oracle_headroom\\\\\\\": 0.10850626942722896,\\\\n  \\\\\\\"ner_fleiss_kappa_mean\\\\\\\": 0.404833077782123,\\\\n  \\\\\\\"ner_soft_jaccard_mean\\\\\\\": 0.7007668853280039,\\\\n  \\\\\\\"ner_correlation_fleiss_vs_f1_full\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.2590287670611875,\\\\n    \\\\\\\"p_value\\\\\\\": 1.4749617362002596e-09,\\\\n    \\\\\\\"n\\\\\\\": 529\\\\n  },\\\\n  \\\\\\\"ner_correlation_softjaccard_vs_f1_full\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.3825183376668469,\\\\n    \\\\\\\"p_value\\\\\\\": 7.075136887733191e-20,\\\\n    \\\\\\\"n\\\\\\\": 529\\\\n  },\\\\n  \\\\\\\"ner_correlation_fleiss_vs_f1_conditional\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.23519998074107282,\\\\n    \\\\\\\"p_value\\\\\\\": 8.162404147668711e-08,\\\\n    \\\\\\\"n\\\\\\\": 508\\\\n  },\\\\n  \\\\\\\"ner_correlation_softjaccard_vs_f1_conditional\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.3761747231572503,\\\\n    \\\\\\\"p_value\\\\\\\": 1.6016428996438062e-18,\\\\n    \\\\\\\"n\\\\\\\": 508\\\\n  },\\\\n  \\\\\\\"ner_n_gold_empty_filtered\\\\\\\": 22,\\\\n  \\\\\\\"ner_n_all_samples_f1_zero_filtered\\\\\\\": 21,\\\\n  \\\\\\\"ner_structural_beats_surface\\\\\\\": true,\\\\n  \\\\\\\"ner_rho_advantage\\\\\\\": 0.1234895706056594,\\\\n  \\\\\\\"ner_sample_f1_mean\\\\\\\": 0.6083957210996992,\\\\n  \\\\\\\"ner_sample_f1_std\\\\\\\": 0.3173545540187574,\\\\n  \\\\\\\"ner_sample_f1_pct_zero\\\\\\\": 12.19281663516068,\\\\n  \\\\\\\"re_greedy_f1\\\\\\\": 0.4207896051974013,\\\\n  \\\\\\\"re_oracle_f1\\\\\\\": 0.5882352941176471,\\\\n  \\\\\\\"re_oracle_headroom\\\\\\\": 0.1674456889202458,\\\\n  \\\\\\\"re_fleiss_kappa_mean\\\\\\\": 0.2996385624366326,\\\\n  \\\\\\\"re_soft_jaccard_mean\\\\\\\": 0.6113509598733148,\\\\n  \\\\\\\"re_correlation_fleiss_vs_f1_full\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.2782151188817765,\\\\n    \\\\\\\"p_value\\\\\\\": 1.7243205365720716e-08,\\\\n    \\\\\\\"n\\\\\\\": 397\\\\n  },\\\\n  \\\\\\\"re_correlation_softjaccard_vs_f1_full\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.2440702831280834,\\\\n    \\\\\\\"p_value\\\\\\\": 8.550224511243979e-07,\\\\n    \\\\\\\"n\\\\\\\": 397\\\\n  },\\\\n  \\\\\\\"re_correlation_fleiss_vs_f1_conditional\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.3067010369107279,\\\\n    \\\\\\\"p_value\\\\\\\": 3.051941342129941e-08,\\\\n    \\\\\\\"n\\\\\\\": 313\\\\n  },\\\\n  \\\\\\\"re_correlation_softjaccard_vs_f1_conditional\\\\\\\": {\\\\n    \\\\\\\"rho\\\\\\\": 0.31612432525905776,\\\\n    \\\\\\\"p_value\\\\\\\": 1.0795971808906936e-08,\\\\n    \\\\\\\"n\\\\\\\": 313\\\\n  },\\\\n  \\\\\\\"re_n_gold_empty_filtered\\\\\\\": 154,\\\\n  \\\\\\\"re_n_all_samples_f1_zero_filtered\\\\\\\": 84,\\\\n  \\\\\\\"re_structural_beats_surface\\\\\\\": false,\\\\n  \\\\\\\"re_rho_advantage\\\\\\\": -0.03414483575369312,\\\\n  \\\\\\\"re_sample_f1_mean\\\\\\\": 0.36116953342051505,\\\\n  \\\\\\\"re_sample_f1_std\\\\\\\": 0.3830344166083389,\\\\n  \\\\\\\"re_sample_f1_pct_zero\\\\\\\": 44.30100755667506,\\\\n  \\\\\\\"verdict\\\\\\\": \\\\\\\"FAIL\\\\\\\",\\\\n  \\\\\\\"verdict_note\\\\\\\": \\\\\\\"Joint mode: verdict requires RE rho_sj >= 0.40 AND rho_sj > rho_fk AND any subtask headroom >= 2pp\\\\\\\",\\\\n  \\\\\\\"warning\\\\\\\": \\\\\\\"WARNING: >30% samples F1=0, recommend re-running at T=0.7\\\\\\\"\\\\n}\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.35}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"dataset\\\": \\\"scierc\\\",\\n  \\\"subtask\\\": \\\"joint\\\",\\n  \\\"n_samples\\\": 8,\\n  \\\"temperature\\\": 1.0,\\n  \\\"num_instances\\\": 551,\\n  \\\"use_train_format\\\": true,\\n  \\\"ner_greedy_f1\\\": 0.6670644391408114,\\n  \\\"ner_oracle_f1\\\": 0.7755707085680403,\\n  \\\"ner_oracle_headroom\\\": 0.10850626942722896,\\n  \\\"ner_fleiss_kappa_mean\\\": 0.404833077782123,\\n  \\\"ner_soft_jaccard_mean\\\": 0.7007668853280039,\\n  \\\"ner_correlation_fleiss_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.2590287670611875,\\n    \\\"p_value\\\": 1.4749617362002596e-09,\\n    \\\"n\\\": 529\\n  },\\n  \\\"ner_correlation_softjaccard_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.3825183376668469,\\n    \\\"p_value\\\": 7.075136887733191e-20,\\n    \\\"n\\\": 529\\n  },\\n  \\\"ner_correlation_fleiss_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.23519998074107282,\\n    \\\"p_value\\\": 8.162404147668711e-08,\\n    \\\"n\\\": 508\\n  },\\n  \\\"ner_correlation_softjaccard_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.3761747231572503,\\n    \\\"p_value\\\": 1.6016428996438062e-18,\\n    \\\"n\\\": 508\\n  },\\n  \\\"ner_n_gold_empty_filtered\\\": 22,\\n  \\\"ner_n_all_samples_f1_zero_filtered\\\": 21,\\n  \\\"ner_structural_beats_surface\\\": true,\\n  \\\"ner_rho_advantage\\\": 0.1234895706056594,\\n  \\\"ner_sample_f1_mean\\\": 0.6083957210996992,\\n  \\\"ner_sample_f1_std\\\": 0.3173545540187574,\\n  \\\"ner_sample_f1_pct_zero\\\": 12.19281663516068,\\n  \\\"re_greedy_f1\\\": 0.4207896051974013,\\n  \\\"re_oracle_f1\\\": 0.5882352941176471,\\n  \\\"re_oracle_headroom\\\": 0.1674456889202458,\\n  \\\"re_fleiss_kappa_mean\\\": 0.2996385624366326,\\n  \\\"re_soft_jaccard_mean\\\": 0.6113509598733148,\\n  \\\"re_correlation_fleiss_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.2782151188817765,\\n    \\\"p_value\\\": 1.7243205365720716e-08,\\n    \\\"n\\\": 397\\n  },\\n  \\\"re_correlation_softjaccard_vs_f1_full\\\": {\\n    \\\"rho\\\": 0.2440702831280834,\\n    \\\"p_value\\\": 8.550224511243979e-07,\\n    \\\"n\\\": 397\\n  },\\n  \\\"re_correlation_fleiss_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.3067010369107279,\\n    \\\"p_value\\\": 3.051941342129941e-08,\\n    \\\"n\\\": 313\\n  },\\n  \\\"re_correlation_softjaccard_vs_f1_conditional\\\": {\\n    \\\"rho\\\": 0.31612432525905776,\\n    \\\"p_value\\\": 1.0795971808906936e-08,\\n    \\\"n\\\": 313\\n  },\\n  \\\"re_n_gold_empty_filtered\\\": 154,\\n  \\\"re_n_all_samples_f1_zero_filtered\\\": 84,\\n  \\\"re_structural_beats_surface\\\": false,\\n  \\\"re_rho_advantage\\\": -0.03414483575369312,\\n  \\\"re_sample_f1_mean\\\": 0.36116953342051505,\\n  \\\"re_sample_f1_std\\\": 0.3830344166083389,\\n  \\\"re_sample_f1_pct_zero\\\": 44.30100755667506,\\n  \\\"verdict\\\": \\\"FAIL\\\",\\n  \\\"verdict_note\\\": \\\"Joint mode: verdict requires RE rho_sj >= 0.40 AND rho_sj > rho_fk AND any subtask headroom >= 2pp\\\",\\n  \\\"warning\\\": \\\"WARNING: >30% samples F1=0, recommend re-running at T=0.7\\\"\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 71_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01MfzT7hYuF1uhFndhogxtNk`</summary>

```json
{
  "server": "autodl-5090",
  "command": "ls /root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed123/ /root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed456/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "6893e738-4833-4479-a3ef-d6e9bd5dd74d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RXhNGBej7taj4taa1yAL1Z",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5043,
      "cache_read_input_tokens": 57934,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5043
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

_source line 72 · 2026-05-21T09:29:40.966Z_

<details><summary>↩ Tool result · `toolu_01MfzT7hYuF1uhFndhogxtNk`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed123/:\\n\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed456/:\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "fea11f87-da52-4083-902a-234fb59cb7ce",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed123/:\\\\n\\\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed456/:\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.36}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed123/:\\n\\n/root/autodl-tmp/struct_self_consist_ie/output/conll_mf4_seed456/:\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 73_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_017gy5KCUH2b7aeKp4VBpcf6`</summary>

```json
{
  "server": "autodl-5090",
  "command": "ls /root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed42/ /root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed123/ /root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed456/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "0aa13cc2-ab99-4f7f-bcd2-94a1e10606b8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RXhNGBej7taj4taa1yAL1Z",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5043,
      "cache_read_input_tokens": 57934,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5043
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

_source line 74 · 2026-05-21T09:29:42.104Z_

<details><summary>↩ Tool result · `toolu_017gy5KCUH2b7aeKp4VBpcf6`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed123/:\\n\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed42/:\\n\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed456/:\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "9bdff168-44cf-4fcf-9002-6a494b3bcfc7",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed123/:\\\\n\\\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed42/:\\\\n\\\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed456/:\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.36}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed123/:\\n\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed42/:\\n\\n/root/autodl-tmp/struct_self_consist_ie/output/scierc_mf4v2_seed456/:\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 75_

<details><summary>Logged reasoning block</summary>

```text
Key findings so far:

1. **mvp_pilot_004** is the original SciERC experiment (old pipeline) - it uses `ner_greedy_f1` = 0.6671 for NER. This is from the JOINT mode (NER+RE), and interestingly it has `ner_greedy_f1` not `greedy_macro_f1`. But the α_crit table shows SciERC greedy = 0.6441 which is lower.


2. The CoNLL MF4 and SciERC MF4v2 output directories are all empty, even though the registry shows some of these experiments as completed. This suggests the results were either deleted or the experiments failed to save their outputs properly.

3. I need to track down the original analysis files that were used to generate the α_crit table, which might involve finding an older script or locating earlier experiment directories with the specific seeds used.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "0b4333a4-740d-4cd3-beb1-8d534f582c37",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X6NwZT6fTYL9oPZYDr8RAX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4155,
      "cache_read_input_tokens": 62977,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4155
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

_source line 76_

CoNLL MF4 和 SciERC MF4v2 目录都是空的。需要找到 α_crit 表的原始数据源。让我查找旧实验数据和分析脚本。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "367d35ce-efab-4290-b716-694aa7f9a180",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X6NwZT6fTYL9oPZYDr8RAX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4155,
      "cache_read_input_tokens": 62977,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4155
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

_source line 77_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_019yeVqRRf5THou9g3nNJeuY`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output -name \"alpha_crit*\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "f5ec5378-3f8f-48c0-9b8b-dff1f6795929",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X6NwZT6fTYL9oPZYDr8RAX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4155,
      "cache_read_input_tokens": 62977,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4155
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

_source line 78 · 2026-05-21T09:29:52.836Z_

<details><summary>↩ Tool result · `toolu_019yeVqRRf5THou9g3nNJeuY`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "7905b162-0273-4429-89c7-7f372c60334a",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.36}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 79_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01VSCdKUVTP9XiQgzZzRKD9K`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie -name \"alpha_crit*\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "2779cb8a-f12a-4667-97f3-e5dc7cd7805b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X6NwZT6fTYL9oPZYDr8RAX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4155,
      "cache_read_input_tokens": 62977,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4155
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

_source line 80 · 2026-05-21T09:29:53.327Z_

<details><summary>↩ Tool result · `toolu_01VSCdKUVTP9XiQgzZzRKD9K`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "eaec2fd9-0c04-4216-8481-363d9172a3b2",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.38}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 81_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01WuBmDmtasKoaFrRriuXETL`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output -maxdepth 2 -name \"entity_construction*\" -o -name \"*entity_voting*\" -o -name \"*mv_analysis*\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "973a03dc-13d7-47a0-a496-e0fbb8090d6f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X6NwZT6fTYL9oPZYDr8RAX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4155,
      "cache_read_input_tokens": 62977,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4155
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

_source line 82 · 2026-05-21T09:29:58.093Z_

<details><summary>↩ Tool result · `toolu_01WuBmDmtasKoaFrRriuXETL`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp014_entity_voting_report.json\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_log.txt\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_n8\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_n8_log.txt\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.63}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "1147cd52-7ebf-4e91-9553-a4b09eba9086",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp014_entity_voting_report.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction\\\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair\\\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_log.txt\\\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_n8\\\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_n8_log.txt\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.63}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp014_entity_voting_report.json\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_log.txt\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_n8\\n/root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_n8_log.txt\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.63}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 83_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01W5Zcb7nneSEx9CoKZvwXZF`</summary>

```json
{
  "server": "autodl-5090",
  "command": "ls /root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_n8/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "0d18de21-2c0e-45a2-b4fa-22de263818f0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0117A9qPquV9wPZ7YZdE8KhQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1281,
      "cache_read_input_tokens": 67132,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1281
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

_source line 84 · 2026-05-21T09:30:01.976Z_

<details><summary>↩ Tool result · `toolu_01W5Zcb7nneSEx9CoKZvwXZF`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"adaptive_combination.json\\nbootstrap_tests.json\\nfair_results.json\\nmultiseed_results.json\\nmultiseed_run.log\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.48}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "b8576bf2-7a1a-4a0d-af2d-b532a6464ce1",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"adaptive_combination.json\\\\nbootstrap_tests.json\\\\nfair_results.json\\\\nmultiseed_results.json\\\\nmultiseed_run.log\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.48}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"adaptive_combination.json\\nbootstrap_tests.json\\nfair_results.json\\nmultiseed_results.json\\nmultiseed_run.log\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.48}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 85_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_016waZFj1vTH2XFxZPSbnFwA`</summary>

```json
{
  "server": "autodl-5090",
  "command": "cat /root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp014_entity_voting_report.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "31064d12-57c1-4502-90bd-c824be3ca83e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0117A9qPquV9wPZ7YZdE8KhQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1281,
      "cache_read_input_tokens": 67132,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1281
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

_source line 86 · 2026-05-21T09:30:03.343Z_

<details><summary>↩ Tool result · `toolu_016waZFj1vTH2XFxZPSbnFwA`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"ner\\\": {\\n    \\\"n_total\\\": 551,\\n    \\\"n_valid\\\": 529,\\n    \\\"n_gold_empty\\\": 22,\\n    \\\"signals\\\": {\\n      \\\"soft_jaccard\\\": {\\n        \\\"rho\\\": 0.3825183376668469,\\n        \\\"p_rho\\\": 7.075136887733191e-20,\\n        \\\"tau\\\": 0.280969525327273,\\n        \\\"p_tau\\\": 6.290620632406763e-20,\\n        \\\"auroc\\\": 0.6896964971555632\\n      },\\n      \\\"fleiss_kappa\\\": {\\n        \\\"rho\\\": 0.2590287670611875,\\n        \\\"p_rho\\\": 1.4749617362002596e-09,\\n        \\\"tau\\\": 0.19205350711403776,\\n        \\\"p_tau\\\": 4.103374950837243e-10,\\n        \\\"auroc\\\": 0.6247364925351584\\n      },\\n      \\\"voting_confidence\\\": {\\n        \\\"rho\\\": 0.39146096117621043,\\n        \\\"p_rho\\\": 8.097233287191834e-21,\\n        \\\"tau\\\": 0.290627994378571,\\n        \\\"p_tau\\\": 5.9522621087435884e-21,\\n        \\\"auroc\\\": 0.7038537064310261\\n      }\\n    },\\n    \\\"strategies\\\": {\\n      \\\"greedy\\\": {\\n        \\\"mean_f1\\\": 0.6483310134149676,\\n        \\\"median_f1\\\": 0.6666666666666666,\\n        \\\"std_f1\\\": 0.3028113844403557\\n      },\\n      \\\"majority_voting\\\": {\\n        \\\"mean_f1\\\": 0.6245747039747636,\\n        \\\"median_f1\\\": 0.6666666666666666,\\n        \\\"std_f1\\\": 0.3137606761561555\\n      },\\n      \\\"true_oracle\\\": {\\n        \\\"mean_f1\\\": 0.7792937633674873,\\n        \\\"median_f1\\\": 0.8571428571428571,\\n        \\\"std_f1\\\": 0.2548279212187456\\n      }\\n    }\\n  },\\n  \\\"re\\\": {\\n    \\\"n_total\\\": 551,\\n    \\\"n_valid\\\": 397,\\n    \\\"n_gold_empty\\\": 154,\\n    \\\"signals\\\": {\\n      \\\"soft_jaccard\\\": {\\n        \\\"rho\\\": 0.2440702831280834,\\n        \\\"p_rho\\\": 8.550224511243979e-07,\\n        \\\"tau\\\": 0.1830505871683703,\\n        \\\"p_tau\\\": 6.33910681437291e-07,\\n        \\\"auroc\\\": 0.6275306237507048\\n      },\\n      \\\"fleiss_kappa\\\": {\\n        \\\"rho\\\": 0.2782151188817765,\\n        \\\"p_rho\\\": 1.7243205365720716e-08,\\n        \\\"tau\\\": 0.21441984772626035,\\n        \\\"p_tau\\\": 5.255501023478468e-09,\\n        \\\"auroc\\\": 0.6483906514273999\\n      },\\n      \\\"voting_confidence\\\": {\\n        \\\"rho\\\": 0.3403002096172365,\\n        \\\"p_rho\\\": 3.2124265554868654e-12,\\n        \\\"tau\\\": 0.2560395530460149,\\n        \\\"p_tau\\\": 3.8877709312147184e-12,\\n        \\\"auroc\\\": 0.6667905284198657\\n      }\\n    },\\n    \\\"strategies\\\": {\\n      \\\"greedy\\\": {\\n        \\\"mean_f1\\\": 0.4022490947257579,\\n        \\\"median_f1\\\": 0.4,\\n        \\\"std_f1\\\": 0.3895411439413035\\n      },\\n      \\\"majority_voting\\\": {\\n        \\\"mean_f1\\\": 0.3576688057466887,\\n        \\\"median_f1\\\": 0.25,\\n        \\\"std_f1\\\": 0.3940265174672826\\n      },\\n      \\\"true_oracle\\\": {\\n        \\\"mean_f1\\\": 0.5886164217731857,\\n        \\\"median_f1\\\": 0.6666666666666666,\\n        \\\"std_f1\\\": 0.3804332905468047\\n      }\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.91}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "d4dbb910-dd18-48da-b97e-6daf687c0a3f",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"ner\\\\\\\": {\\\\n    \\\\\\\"n_total\\\\\\\": 551,\\\\n    \\\\\\\"n_valid\\\\\\\": 529,\\\\n    \\\\\\\"n_gold_empty\\\\\\\": 22,\\\\n    \\\\\\\"signals\\\\\\\": {\\\\n      \\\\\\\"soft_jaccard\\\\\\\": {\\\\n        \\\\\\\"rho\\\\\\\": 0.3825183376668469,\\\\n        \\\\\\\"p_rho\\\\\\\": 7.075136887733191e-20,\\\\n        \\\\\\\"tau\\\\\\\": 0.280969525327273,\\\\n        \\\\\\\"p_tau\\\\\\\": 6.290620632406763e-20,\\\\n        \\\\\\\"auroc\\\\\\\": 0.6896964971555632\\\\n      },\\\\n      \\\\\\\"fleiss_kappa\\\\\\\": {\\\\n        \\\\\\\"rho\\\\\\\": 0.2590287670611875,\\\\n        \\\\\\\"p_rho\\\\\\\": 1.4749617362002596e-09,\\\\n        \\\\\\\"tau\\\\\\\": 0.19205350711403776,\\\\n        \\\\\\\"p_tau\\\\\\\": 4.103374950837243e-10,\\\\n        \\\\\\\"auroc\\\\\\\": 0.6247364925351584\\\\n      },\\\\n      \\\\\\\"voting_confidence\\\\\\\": {\\\\n        \\\\\\\"rho\\\\\\\": 0.39146096117621043,\\\\n        \\\\\\\"p_rho\\\\\\\": 8.097233287191834e-21,\\\\n        \\\\\\\"tau\\\\\\\": 0.290627994378571,\\\\n        \\\\\\\"p_tau\\\\\\\": 5.9522621087435884e-21,\\\\n        \\\\\\\"auroc\\\\\\\": 0.7038537064310261\\\\n      }\\\\n    },\\\\n    \\\\\\\"strategies\\\\\\\": {\\\\n      \\\\\\\"greedy\\\\\\\": {\\\\n        \\\\\\\"mean_f1\\\\\\\": 0.6483310134149676,\\\\n        \\\\\\\"median_f1\\\\\\\": 0.6666666666666666,\\\\n        \\\\\\\"std_f1\\\\\\\": 0.3028113844403557\\\\n      },\\\\n      \\\\\\\"majority_voting\\\\\\\": {\\\\n        \\\\\\\"mean_f1\\\\\\\": 0.6245747039747636,\\\\n        \\\\\\\"median_f1\\\\\\\": 0.6666666666666666,\\\\n        \\\\\\\"std_f1\\\\\\\": 0.3137606761561555\\\\n      },\\\\n      \\\\\\\"true_oracle\\\\\\\": {\\\\n        \\\\\\\"mean_f1\\\\\\\": 0.7792937633674873,\\\\n        \\\\\\\"median_f1\\\\\\\": 0.8571428571428571,\\\\n        \\\\\\\"std_f1\\\\\\\": 0.2548279212187456\\\\n      }\\\\n    }\\\\n  },\\\\n  \\\\\\\"re\\\\\\\": {\\\\n    \\\\\\\"n_total\\\\\\\": 551,\\\\n    \\\\\\\"n_valid\\\\\\\": 397,\\\\n    \\\\\\\"n_gold_empty\\\\\\\": 154,\\\\n    \\\\\\\"signals\\\\\\\": {\\\\n      \\\\\\\"soft_jaccard\\\\\\\": {\\\\n        \\\\\\\"rho\\\\\\\": 0.2440702831280834,\\\\n        \\\\\\\"p_rho\\\\\\\": 8.550224511243979e-07,\\\\n        \\\\\\\"tau\\\\\\\": 0.1830505871683703,\\\\n        \\\\\\\"p_tau\\\\\\\": 6.33910681437291e-07,\\\\n        \\\\\\\"auroc\\\\\\\": 0.6275306237507048\\\\n      },\\\\n      \\\\\\\"fleiss_kappa\\\\\\\": {\\\\n        \\\\\\\"rho\\\\\\\": 0.2782151188817765,\\\\n        \\\\\\\"p_rho\\\\\\\": 1.7243205365720716e-08,\\\\n        \\\\\\\"tau\\\\\\\": 0.21441984772626035,\\\\n        \\\\\\\"p_tau\\\\\\\": 5.255501023478468e-09,\\\\n        \\\\\\\"auroc\\\\\\\": 0.6483906514273999\\\\n      },\\\\n      \\\\\\\"voting_confidence\\\\\\\": {\\\\n        \\\\\\\"rho\\\\\\\": 0.3403002096172365,\\\\n        \\\\\\\"p_rho\\\\\\\": 3.2124265554868654e-12,\\\\n        \\\\\\\"tau\\\\\\\": 0.2560395530460149,\\\\n        \\\\\\\"p_tau\\\\\\\": 3.8877709312147184e-12,\\\\n        \\\\\\\"auroc\\\\\\\": 0.6667905284198657\\\\n      }\\\\n    },\\\\n    \\\\\\\"strategies\\\\\\\": {\\\\n      \\\\\\\"greedy\\\\\\\": {\\\\n        \\\\\\\"mean_f1\\\\\\\": 0.4022490947257579,\\\\n        \\\\\\\"median_f1\\\\\\\": 0.4,\\\\n        \\\\\\\"std_f1\\\\\\\": 0.3895411439413035\\\\n      },\\\\n      \\\\\\\"majority_voting\\\\\\\": {\\\\n        \\\\\\\"mean_f1\\\\\\\": 0.3576688057466887,\\\\n        \\\\\\\"median_f1\\\\\\\": 0.25,\\\\n        \\\\\\\"std_f1\\\\\\\": 0.3940265174672826\\\\n      },\\\\n      \\\\\\\"true_oracle\\\\\\\": {\\\\n        \\\\\\\"mean_f1\\\\\\\": 0.5886164217731857,\\\\n        \\\\\\\"median_f1\\\\\\\": 0.6666666666666666,\\\\n        \\\\\\\"std_f1\\\\\\\": 0.3804332905468047\\\\n      }\\\\n    }\\\\n  }\\\\n}\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.91}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"ner\\\": {\\n    \\\"n_total\\\": 551,\\n    \\\"n_valid\\\": 529,\\n    \\\"n_gold_empty\\\": 22,\\n    \\\"signals\\\": {\\n      \\\"soft_jaccard\\\": {\\n        \\\"rho\\\": 0.3825183376668469,\\n        \\\"p_rho\\\": 7.075136887733191e-20,\\n        \\\"tau\\\": 0.280969525327273,\\n        \\\"p_tau\\\": 6.290620632406763e-20,\\n        \\\"auroc\\\": 0.6896964971555632\\n      },\\n      \\\"fleiss_kappa\\\": {\\n        \\\"rho\\\": 0.2590287670611875,\\n        \\\"p_rho\\\": 1.4749617362002596e-09,\\n        \\\"tau\\\": 0.19205350711403776,\\n        \\\"p_tau\\\": 4.103374950837243e-10,\\n        \\\"auroc\\\": 0.6247364925351584\\n      },\\n      \\\"voting_confidence\\\": {\\n        \\\"rho\\\": 0.39146096117621043,\\n        \\\"p_rho\\\": 8.097233287191834e-21,\\n        \\\"tau\\\": 0.290627994378571,\\n        \\\"p_tau\\\": 5.9522621087435884e-21,\\n        \\\"auroc\\\": 0.7038537064310261\\n      }\\n    },\\n    \\\"strategies\\\": {\\n      \\\"greedy\\\": {\\n        \\\"mean_f1\\\": 0.6483310134149676,\\n        \\\"median_f1\\\": 0.6666666666666666,\\n        \\\"std_f1\\\": 0.3028113844403557\\n      },\\n      \\\"majority_voting\\\": {\\n        \\\"mean_f1\\\": 0.6245747039747636,\\n        \\\"median_f1\\\": 0.6666666666666666,\\n        \\\"std_f1\\\": 0.3137606761561555\\n      },\\n      \\\"true_oracle\\\": {\\n        \\\"mean_f1\\\": 0.7792937633674873,\\n        \\\"median_f1\\\": 0.8571428571428571,\\n        \\\"std_f1\\\": 0.2548279212187456\\n      }\\n    }\\n  },\\n  \\\"re\\\": {\\n    \\\"n_total\\\": 551,\\n    \\\"n_valid\\\": 397,\\n    \\\"n_gold_empty\\\": 154,\\n    \\\"signals\\\": {\\n      \\\"soft_jaccard\\\": {\\n        \\\"rho\\\": 0.2440702831280834,\\n        \\\"p_rho\\\": 8.550224511243979e-07,\\n        \\\"tau\\\": 0.1830505871683703,\\n        \\\"p_tau\\\": 6.33910681437291e-07,\\n        \\\"auroc\\\": 0.6275306237507048\\n      },\\n      \\\"fleiss_kappa\\\": {\\n        \\\"rho\\\": 0.2782151188817765,\\n        \\\"p_rho\\\": 1.7243205365720716e-08,\\n        \\\"tau\\\": 0.21441984772626035,\\n        \\\"p_tau\\\": 5.255501023478468e-09,\\n        \\\"auroc\\\": 0.6483906514273999\\n      },\\n      \\\"voting_confidence\\\": {\\n        \\\"rho\\\": 0.3403002096172365,\\n        \\\"p_rho\\\": 3.2124265554868654e-12,\\n        \\\"tau\\\": 0.2560395530460149,\\n        \\\"p_tau\\\": 3.8877709312147184e-12,\\n        \\\"auroc\\\": 0.6667905284198657\\n      }\\n    },\\n    \\\"strategies\\\": {\\n      \\\"greedy\\\": {\\n        \\\"mean_f1\\\": 0.4022490947257579,\\n        \\\"median_f1\\\": 0.4,\\n        \\\"std_f1\\\": 0.3895411439413035\\n      },\\n      \\\"majority_voting\\\": {\\n        \\\"mean_f1\\\": 0.3576688057466887,\\n        \\\"median_f1\\\": 0.25,\\n        \\\"std_f1\\\": 0.3940265174672826\\n      },\\n      \\\"true_oracle\\\": {\\n        \\\"mean_f1\\\": 0.5886164217731857,\\n        \\\"median_f1\\\": 0.6666666666666666,\\n        \\\"std_f1\\\": 0.3804332905468047\\n      }\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.91}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 87_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01PG1FFqDRWHrupoauzePJur`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output -maxdepth 2 -name \"construction_variants\" -o -name \"review_round*\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "f66251ff-6aa1-40fb-b636-f8422e719844",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0117A9qPquV9wPZ7YZdE8KhQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1281,
      "cache_read_input_tokens": 67132,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1281
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

_source line 88 · 2026-05-21T09:30:03.828Z_

<details><summary>↩ Tool result · `toolu_01PG1FFqDRWHrupoauzePJur`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/review_round2\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round4\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round8\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round9_experiments\\n/root/autodl-tmp/struct_self_consist_ie/output/construction_variants\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "d7c4dd8c-ef50-4aed-a422-69d504141290",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/review_round2\\\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round4\\\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round8\\\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round9_experiments\\\\n/root/autodl-tmp/struct_self_consist_ie/output/construction_variants\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.4}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/review_round2\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round4\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round8\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round9_experiments\\n/root/autodl-tmp/struct_self_consist_ie/output/construction_variants\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 89_

<details><summary>Logged reasoning block</summary>

```text
Key findings:

1. **mvp_pilot_004/exp014_entity_voting_report.json** (SciERC old pipeline):
   - NER greedy **mean_f1** = 0.6483 (this is macro/mean F1 over instances)
   - NER majority_voting **mean_f1** = 0.6246
   - NER oracle **mean_f1** = 0.7793

2. The α_crit table shows SciERC: greedy=0.6441, MV=0.6138, oracle=0.7746

These don't match exactly. 

I'm noticing that mvp_pilot_004 uses macro-averaged F1 scores computed across instances, which differs from micro-F1 that aggregates true positives and false positives first. The slight discrepancies between these values and the α_crit table suggest I should check the multiseed_results.json file to identify the actual source of the reported metrics.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "16950181-46c1-4a24-a00d-7be906364ebc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QbMzNa4YeojCmx8ccscLYL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2299,
      "cache_read_input_tokens": 68413,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2299
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

_source line 90_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01DX9rkR2Q7dK6MWkLW7AN5X`</summary>

```json
{
  "server": "autodl-5090",
  "command": "cat /root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_n8/multiseed_results.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "df855c49-7ebb-425e-badd-133058e0086d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QbMzNa4YeojCmx8ccscLYL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2299,
      "cache_read_input_tokens": 68413,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2299
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

_source line 91_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01FSDEXFneJmWMZr6dsYdZU7`</summary>

```json
{
  "server": "autodl-5090",
  "command": "cat /root/autodl-tmp/struct_self_consist_ie/output/entity_construction_fair_n8/fair_results.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "2da0c862-c95c-423a-a92b-804fb4017475",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QbMzNa4YeojCmx8ccscLYL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2299,
      "cache_read_input_tokens": 68413,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2299
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

_source line 92 · 2026-05-21T09:30:13.820Z_

<details><summary>↩ Tool result · `toolu_01DX9rkR2Q7dK6MWkLW7AN5X`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"scierc\\\": {\\n    \\\"per_seed\\\": {\\n      \\\"42\\\": {\\n        \\\"n_instances\\\": 529,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.6439219990259687,\\n        \\\"uniform_construction_f1\\\": 0.6593292957102236,\\n        \\\"lp_weighted_construction_f1\\\": 0.6606099142231339,\\n        \\\"delta_uniform\\\": 0.015407296684254787,\\n        \\\"delta_lp_weighted\\\": 0.016687915197165084\\n      },\\n      \\\"123\\\": {\\n        \\\"n_instances\\\": 529,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.6457455273145254,\\n        \\\"uniform_construction_f1\\\": 0.6545081200190971,\\n        \\\"lp_weighted_construction_f1\\\": 0.6547635091436067,\\n        \\\"delta_uniform\\\": 0.008762592704571732,\\n        \\\"delta_lp_weighted\\\": 0.009017981829081282\\n      },\\n      \\\"456\\\": {\\n        \\\"n_instances\\\": 529,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.6478253358882736,\\n        \\\"uniform_construction_f1\\\": 0.6458989893188715,\\n        \\\"lp_weighted_construction_f1\\\": 0.6527717176999952,\\n        \\\"delta_uniform\\\": -0.0019263465694022823,\\n        \\\"delta_lp_weighted\\\": 0.00494638181172152\\n      }\\n    },\\n    \\\"summary\\\": {\\n      \\\"n_seeds\\\": 3,\\n      \\\"greedy_f1_mean\\\": 0.6458309540762559,\\n      \\\"greedy_f1_std\\\": 0.0015946750899732823,\\n      \\\"uniform_f1_mean\\\": 0.6532454683493975,\\n      \\\"uniform_f1_std\\\": 0.005555117722763698,\\n      \\\"lp_weighted_f1_mean\\\": 0.6560483803555786,\\n      \\\"lp_weighted_f1_std\\\": 0.00332640964678649,\\n      \\\"delta_uniform_mean\\\": 0.007414514273141413,\\n      \\\"delta_uniform_std\\\": 0.007140344702427586,\\n      \\\"delta_lp_mean\\\": 0.010217426279322627,\\n      \\\"delta_lp_std\\\": 0.004867915488329854\\n    }\\n  },\\n  \\\"fewnerd\\\": {\\n    \\\"per_seed\\\": {\\n      \\\"42\\\": {\\n        \\\"n_instances\\\": 32565,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.7478465965854552,\\n        \\\"uniform_construction_f1\\\": 0.7510129759717606,\\n        \\\"lp_weighted_construction_f1\\\": 0.7566255838444086,\\n        \\\"delta_uniform\\\": 0.0031663793863054316,\\n        \\\"delta_lp_weighted\\\": 0.00877898725895342\\n      },\\n      \\\"123\\\": {\\n        \\\"n_instances\\\": 32565,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.7480463604385982,\\n        \\\"uniform_construction_f1\\\": 0.7652086763964873,\\n        \\\"lp_weighted_construction_f1\\\": 0.769875068001411,\\n        \\\"delta_uniform\\\": 0.017162315957889154,\\n        \\\"delta_lp_weighted\\\": 0.021828707562812927\\n      },\\n      \\\"456\\\": {\\n        \\\"n_instances\\\": 32565,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.7486020812401402,\\n        \\\"uniform_construction_f1\\\": 0.7550106984828937,\\n        \\\"lp_weighted_construction_f1\\\": 0.7637261649123498,\\n        \\\"delta_uniform\\\": 0.006408617242753546,\\n        \\\"delta_lp_weighted\\\": 0.015124083672209576\\n      },\\n      \\\"789\\\": {\\n        \\\"n_instances\\\": 32565,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.7477603920094339,\\n        \\\"uniform_construction_f1\\\": 0.7507543454156034,\\n        \\\"lp_weighted_construction_f1\\\": 0.7579738648297688,\\n        \\\"delta_uniform\\\": 0.002993953406169472,\\n        \\\"delta_lp_weighted\\\": 0.010213472820335016\\n      }\\n    },\\n    \\\"summary\\\": {\\n      \\\"n_seeds\\\": 4,\\n      \\\"greedy_f1_mean\\\": 0.7480638575684068,\\n      \\\"greedy_f1_std\\\": 0.0003275990501213073,\\n      \\\"uniform_f1_mean\\\": 0.7554966740666862,\\n      \\\"uniform_f1_std\\\": 0.005855603964652662,\\n      \\\"lp_weighted_f1_mean\\\": 0.7620501703969845,\\n      \\\"lp_weighted_f1_std\\\": 0.005245960028417003,\\n      \\\"delta_uniform_mean\\\": 0.0074328164982794005,\\n      \\\"delta_uniform_std\\\": 0.005779665540290604,\\n      \\\"delta_lp_mean\\\": 0.013986312828577735,\\n      \\\"delta_lp_std\\\": 0.005102652226441626\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "2c7f91da-4d9f-40ce-9f8c-17eda698f326",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"scierc\\\\\\\": {\\\\n    \\\\\\\"per_seed\\\\\\\": {\\\\n      \\\\\\\"42\\\\\\\": {\\\\n        \\\\\\\"n_instances\\\\\\\": 529,\\\\n        \\\\\\\"n_samples\\\\\\\": 8,\\\\n        \\\\\\\"theta\\\\\\\": 0.25,\\\\n        \\\\\\\"greedy_f1\\\\\\\": 0.6439219990259687,\\\\n        \\\\\\\"uniform_construction_f1\\\\\\\": 0.6593292957102236,\\\\n        \\\\\\\"lp_weighted_construction_f1\\\\\\\": 0.6606099142231339,\\\\n        \\\\\\\"delta_uniform\\\\\\\": 0.015407296684254787,\\\\n        \\\\\\\"delta_lp_weighted\\\\\\\": 0.016687915197165084\\\\n      },\\\\n      \\\\\\\"123\\\\\\\": {\\\\n        \\\\\\\"n_instances\\\\\\\": 529,\\\\n        \\\\\\\"n_samples\\\\\\\": 8,\\\\n        \\\\\\\"theta\\\\\\\": 0.25,\\\\n        \\\\\\\"greedy_f1\\\\\\\": 0.6457455273145254,\\\\n        \\\\\\\"uniform_construction_f1\\\\\\\": 0.6545081200190971,\\\\n        \\\\\\\"lp_weighted_construction_f1\\\\\\\": 0.6547635091436067,\\\\n        \\\\\\\"delta_uniform\\\\\\\": 0.008762592704571732,\\\\n        \\\\\\\"delta_lp_weighted\\\\\\\": 0.009017981829081282\\\\n      },\\\\n      \\\\\\\"456\\\\\\\": {\\\\n        \\\\\\\"n_instances\\\\\\\": 529,\\\\n        \\\\\\\"n_samples\\\\\\\": 8,\\\\n        \\\\\\\"theta\\\\\\\": 0.25,\\\\n        \\\\\\\"greedy_f1\\\\\\\": 0.6478253358882736,\\\\n        \\\\\\\"uniform_construction_f1\\\\\\\": 0.6458989893188715,\\\\n        \\\\\\\"lp_weighted_construction_f1\\\\\\\": 0.6527717176999952,\\\\n        \\\\\\\"delta_uniform\\\\\\\": -0.0019263465694022823,\\\\n        \\\\\\\"delta_lp_weighted\\\\\\\": 0.00494638181172152\\\\n      }\\\\n    },\\\\n    \\\\\\\"summary\\\\\\\": {\\\\n      \\\\\\\"n_seeds\\\\\\\": 3,\\\\n      \\\\\\\"greedy_f1_mean\\\\\\\": 0.6458309540762559,\\\\n      \\\\\\\"greedy_f1_std\\\\\\\": 0.0015946750899732823,\\\\n      \\\\\\\"uniform_f1_mean\\\\\\\": 0.6532454683493975,\\\\n      \\\\\\\"uniform_f1_std\\\\\\\": 0.005555117722763698,\\\\n      \\\\\\\"lp_weighted_f1_mean\\\\\\\": 0.6560483803555786,\\\\n      \\\\\\\"lp_weighted_f1_std\\\\\\\": 0.00332640964678649,\\\\n      \\\\\\\"delta_uniform_mean\\\\\\\": 0.007414514273141413,\\\\n      \\\\\\\"delta_uniform_std\\\\\\\": 0.007140344702427586,\\\\n      \\\\\\\"delta_lp_mean\\\\\\\": 0.010217426279322627,\\\\n      \\\\\\\"delta_lp_std\\\\\\\": 0.004867915488329854\\\\n    }\\\\n  },\\\\n  \\\\\\\"fewnerd\\\\\\\": {\\\\n    \\\\\\\"per_seed\\\\\\\": {\\\\n      \\\\\\\"42\\\\\\\": {\\\\n        \\\\\\\"n_instances\\\\\\\": 32565,\\\\n        \\\\\\\"n_samples\\\\\\\": 8,\\\\n        \\\\\\\"theta\\\\\\\": 0.25,\\\\n        \\\\\\\"greedy_f1\\\\\\\": 0.7478465965854552,\\\\n        \\\\\\\"uniform_construction_f1\\\\\\\": 0.7510129759717606,\\\\n        \\\\\\\"lp_weighted_construction_f1\\\\\\\": 0.7566255838444086,\\\\n        \\\\\\\"delta_uniform\\\\\\\": 0.0031663793863054316,\\\\n        \\\\\\\"delta_lp_weighted\\\\\\\": 0.00877898725895342\\\\n      },\\\\n      \\\\\\\"123\\\\\\\": {\\\\n        \\\\\\\"n_instances\\\\\\\": 32565,\\\\n        \\\\\\\"n_samples\\\\\\\": 8,\\\\n        \\\\\\\"theta\\\\\\\": 0.25,\\\\n        \\\\\\\"greedy_f1\\\\\\\": 0.7480463604385982,\\\\n        \\\\\\\"uniform_construction_f1\\\\\\\": 0.7652086763964873,\\\\n        \\\\\\\"lp_weighted_construction_f1\\\\\\\": 0.769875068001411,\\\\n        \\\\\\\"delta_uniform\\\\\\\": 0.017162315957889154,\\\\n        \\\\\\\"delta_lp_weighted\\\\\\\": 0.021828707562812927\\\\n      },\\\\n      \\\\\\\"456\\\\\\\": {\\\\n        \\\\\\\"n_instances\\\\\\\": 32565,\\\\n        \\\\\\\"n_samples\\\\\\\": 8,\\\\n        \\\\\\\"theta\\\\\\\": 0.25,\\\\n        \\\\\\\"greedy_f1\\\\\\\": 0.7486020812401402,\\\\n        \\\\\\\"uniform_construction_f1\\\\\\\": 0.7550106984828937,\\\\n        \\\\\\\"lp_weighted_construction_f1\\\\\\\": 0.7637261649123498,\\\\n        \\\\\\\"delta_uniform\\\\\\\": 0.006408617242753546,\\\\n        \\\\\\\"delta_lp_weighted\\\\\\\": 0.015124083672209576\\\\n      },\\\\n      \\\\\\\"789\\\\\\\": {\\\\n        \\\\\\\"n_instances\\\\\\\": 32565,\\\\n        \\\\\\\"n_samples\\\\\\\": 8,\\\\n        \\\\\\\"theta\\\\\\\": 0.25,\\\\n        \\\\\\\"greedy_f1\\\\\\\": 0.7477603920094339,\\\\n        \\\\\\\"uniform_construction_f1\\\\\\\": 0.7507543454156034,\\\\n        \\\\\\\"lp_weighted_construction_f1\\\\\\\": 0.7579738648297688,\\\\n        \\\\\\\"delta_uniform\\\\\\\": 0.002993953406169472,\\\\n        \\\\\\\"delta_lp_weighted\\\\\\\": 0.010213472820335016\\\\n      }\\\\n    },\\\\n    \\\\\\\"summary\\\\\\\": {\\\\n      \\\\\\\"n_seeds\\\\\\\": 4,\\\\n      \\\\\\\"greedy_f1_mean\\\\\\\": 0.7480638575684068,\\\\n      \\\\\\\"greedy_f1_std\\\\\\\": 0.0003275990501213073,\\\\n      \\\\\\\"uniform_f1_mean\\\\\\\": 0.7554966740666862,\\\\n      \\\\\\\"uniform_f1_std\\\\\\\": 0.005855603964652662,\\\\n      \\\\\\\"lp_weighted_f1_mean\\\\\\\": 0.7620501703969845,\\\\n      \\\\\\\"lp_weighted_f1_std\\\\\\\": 0.005245960028417003,\\\\n      \\\\\\\"delta_uniform_mean\\\\\\\": 0.0074328164982794005,\\\\n      \\\\\\\"delta_uniform_std\\\\\\\": 0.005779665540290604,\\\\n      \\\\\\\"delta_lp_mean\\\\\\\": 0.013986312828577735,\\\\n      \\\\\\\"delta_lp_std\\\\\\\": 0.005102652226441626\\\\n    }\\\\n  }\\\\n}\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.4}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"scierc\\\": {\\n    \\\"per_seed\\\": {\\n      \\\"42\\\": {\\n        \\\"n_instances\\\": 529,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.6439219990259687,\\n        \\\"uniform_construction_f1\\\": 0.6593292957102236,\\n        \\\"lp_weighted_construction_f1\\\": 0.6606099142231339,\\n        \\\"delta_uniform\\\": 0.015407296684254787,\\n        \\\"delta_lp_weighted\\\": 0.016687915197165084\\n      },\\n      \\\"123\\\": {\\n        \\\"n_instances\\\": 529,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.6457455273145254,\\n        \\\"uniform_construction_f1\\\": 0.6545081200190971,\\n        \\\"lp_weighted_construction_f1\\\": 0.6547635091436067,\\n        \\\"delta_uniform\\\": 0.008762592704571732,\\n        \\\"delta_lp_weighted\\\": 0.009017981829081282\\n      },\\n      \\\"456\\\": {\\n        \\\"n_instances\\\": 529,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.6478253358882736,\\n        \\\"uniform_construction_f1\\\": 0.6458989893188715,\\n        \\\"lp_weighted_construction_f1\\\": 0.6527717176999952,\\n        \\\"delta_uniform\\\": -0.0019263465694022823,\\n        \\\"delta_lp_weighted\\\": 0.00494638181172152\\n      }\\n    },\\n    \\\"summary\\\": {\\n      \\\"n_seeds\\\": 3,\\n      \\\"greedy_f1_mean\\\": 0.6458309540762559,\\n      \\\"greedy_f1_std\\\": 0.0015946750899732823,\\n      \\\"uniform_f1_mean\\\": 0.6532454683493975,\\n      \\\"uniform_f1_std\\\": 0.005555117722763698,\\n      \\\"lp_weighted_f1_mean\\\": 0.6560483803555786,\\n      \\\"lp_weighted_f1_std\\\": 0.00332640964678649,\\n      \\\"delta_uniform_mean\\\": 0.007414514273141413,\\n      \\\"delta_uniform_std\\\": 0.007140344702427586,\\n      \\\"delta_lp_mean\\\": 0.010217426279322627,\\n      \\\"delta_lp_std\\\": 0.004867915488329854\\n    }\\n  },\\n  \\\"fewnerd\\\": {\\n    \\\"per_seed\\\": {\\n      \\\"42\\\": {\\n        \\\"n_instances\\\": 32565,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.7478465965854552,\\n        \\\"uniform_construction_f1\\\": 0.7510129759717606,\\n        \\\"lp_weighted_construction_f1\\\": 0.7566255838444086,\\n        \\\"delta_uniform\\\": 0.0031663793863054316,\\n        \\\"delta_lp_weighted\\\": 0.00877898725895342\\n      },\\n      \\\"123\\\": {\\n        \\\"n_instances\\\": 32565,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.7480463604385982,\\n        \\\"uniform_construction_f1\\\": 0.7652086763964873,\\n        \\\"lp_weighted_construction_f1\\\": 0.769875068001411,\\n        \\\"delta_uniform\\\": 0.017162315957889154,\\n        \\\"delta_lp_weighted\\\": 0.021828707562812927\\n      },\\n      \\\"456\\\": {\\n        \\\"n_instances\\\": 32565,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.7486020812401402,\\n        \\\"uniform_construction_f1\\\": 0.7550106984828937,\\n        \\\"lp_weighted_construction_f1\\\": 0.7637261649123498,\\n        \\\"delta_uniform\\\": 0.006408617242753546,\\n        \\\"delta_lp_weighted\\\": 0.015124083672209576\\n      },\\n      \\\"789\\\": {\\n        \\\"n_instances\\\": 32565,\\n        \\\"n_samples\\\": 8,\\n        \\\"theta\\\": 0.25,\\n        \\\"greedy_f1\\\": 0.7477603920094339,\\n        \\\"uniform_construction_f1\\\": 0.7507543454156034,\\n        \\\"lp_weighted_construction_f1\\\": 0.7579738648297688,\\n        \\\"delta_uniform\\\": 0.002993953406169472,\\n        \\\"delta_lp_weighted\\\": 0.010213472820335016\\n      }\\n    },\\n    \\\"summary\\\": {\\n      \\\"n_seeds\\\": 4,\\n      \\\"greedy_f1_mean\\\": 0.7480638575684068,\\n      \\\"greedy_f1_std\\\": 0.0003275990501213073,\\n      \\\"uniform_f1_mean\\\": 0.7554966740666862,\\n      \\\"uniform_f1_std\\\": 0.005855603964652662,\\n      \\\"lp_weighted_f1_mean\\\": 0.7620501703969845,\\n      \\\"lp_weighted_f1_std\\\": 0.005245960028417003,\\n      \\\"delta_uniform_mean\\\": 0.0074328164982794005,\\n      \\\"delta_uniform_std\\\": 0.005779665540290604,\\n      \\\"delta_lp_mean\\\": 0.013986312828577735,\\n      \\\"delta_lp_std\\\": 0.005102652226441626\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4}}"
    }
  }
}
```

</details>

---


### Tool result

_source line 93 · 2026-05-21T09:30:14.805Z_

<details><summary>↩ Tool result · `toolu_01FSDEXFneJmWMZr6dsYdZU7`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"scierc\\\": {\\n    \\\"greedy\\\": {\\n      \\\"F1\\\": 0.6439219990259687,\\n      \\\"std\\\": 0.30526978546327577\\n    },\\n    \\\"lp_selection\\\": {\\n      \\\"F1\\\": 0.6500718843902431,\\n      \\\"std\\\": 0.29705508172192924\\n    },\\n    \\\"sj_selection\\\": {\\n      \\\"F1\\\": 0.5930517864827884,\\n      \\\"std\\\": 0.3373844979835319\\n    },\\n    \\\"oracle\\\": {\\n      \\\"F1\\\": 0.7758023559647044,\\n      \\\"std\\\": 0.253799245007122\\n    },\\n    \\\"random\\\": {\\n      \\\"F1\\\": 0.6090607200574826,\\n      \\\"std\\\": 0.25985586541169237\\n    },\\n    \\\"construction_uniform_majority\\\": {\\n      \\\"F1\\\": 0.653641905167507,\\n      \\\"std\\\": 0.3010870867244481,\\n      \\\"theta\\\": 0.5\\n    },\\n    \\\"construction_uniform_confirm\\\": {\\n      \\\"F1\\\": 0.6593292957102236,\\n      \\\"std\\\": 0.2679778282300995,\\n      \\\"theta\\\": 0.25\\n    },\\n    \\\"construction_uniform_cv\\\": {\\n      \\\"F1\\\": 0.6552371710387132,\\n      \\\"std\\\": 0.0279304877311693,\\n      \\\"fold_f1s\\\": [\\n        0.6654736328751916,\\n        0.6439552062193571,\\n        0.6390221475404606,\\n        0.6235152164397447,\\n        0.7042196521188119\\n      ],\\n      \\\"fold_thetas\\\": [\\n        0.3,\\n        0.15,\\n        0.15,\\n        0.3,\\n        0.3\\n      ]\\n    },\\n    \\\"bootstrap_construction_uniform_majority_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.009719906141538169,\\n      \\\"ci_95\\\": [\\n        -0.0025668807646749554,\\n        0.022544121575769724\\n      ],\\n      \\\"p_value\\\": 0.0652,\\n      \\\"significant\\\": false\\n    },\\n    \\\"bootstrap_construction_uniform_confirm_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.015407296684254787,\\n      \\\"ci_95\\\": [\\n        0.0002982097298436904,\\n        0.031248574994734275\\n      ],\\n      \\\"p_value\\\": 0.0233,\\n      \\\"significant\\\": true\\n    },\\n    \\\"bootstrap_construction_uniform_cv_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.011222577530551364,\\n      \\\"ci_95\\\": [\\n        -0.002930266201421545,\\n        0.026136005774118017\\n      ],\\n      \\\"p_value\\\": 0.0573,\\n      \\\"significant\\\": false\\n    },\\n    \\\"bootstrap_lp_selection_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.006149885364274336,\\n      \\\"ci_95\\\": [\\n        -0.007718206771915206,\\n        0.01993277103717168\\n      ],\\n      \\\"p_value\\\": 0.193,\\n      \\\"significant\\\": false\\n    },\\n    \\\"construction_lp_weighted_majority\\\": {\\n      \\\"F1\\\": 0.6484769797757384,\\n      \\\"std\\\": 0.3065424667758378,\\n      \\\"theta\\\": 0.5\\n    },\\n    \\\"construction_lp_weighted_confirm\\\": {\\n      \\\"F1\\\": 0.6606099142231339,\\n      \\\"std\\\": 0.2803411122678887,\\n      \\\"theta\\\": 0.25\\n    },\\n    \\\"construction_lp_weighted_cv\\\": {\\n      \\\"F1\\\": 0.6565108240104793,\\n      \\\"std\\\": 0.02752929887287152,\\n      \\\"fold_f1s\\\": [\\n        0.6654736328751916,\\n        0.650323471078188,\\n        0.6390221475404606,\\n        0.6235152164397447,\\n        0.7042196521188119\\n      ],\\n      \\\"fold_thetas\\\": [\\n        0.3,\\n        0.25,\\n        0.15,\\n        0.3,\\n        0.3\\n      ]\\n    },\\n    \\\"bootstrap_construction_lp_weighted_majority_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.004554980749769676,\\n      \\\"ci_95\\\": [\\n        -0.008595347655771845,\\n        0.0175267203869311\\n      ],\\n      \\\"p_value\\\": 0.2438,\\n      \\\"significant\\\": false\\n    },\\n    \\\"bootstrap_construction_lp_weighted_confirm_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.016687915197165084,\\n      \\\"ci_95\\\": [\\n        0.003708882393845699,\\n        0.030250983686895105\\n      ],\\n      \\\"p_value\\\": 0.0044,\\n      \\\"significant\\\": true\\n    },\\n    \\\"bootstrap_construction_lp_weighted_cv_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.01249863816388988,\\n      \\\"ci_95\\\": [\\n        -0.0008866984975969504,\\n        0.02678501619452975\\n      ],\\n      \\\"p_value\\\": 0.0351,\\n      \\\"significant\\\": true\\n    },\\n    \\\"adaptive_uniform\\\": {\\n      \\\"F1\\\": -1.0,\\n      \\\"std\\\": 0.0,\\n      \\\"fold_f1s\\\": [\\n        -1.0,\\n        -1.0,\\n        -1.0,\\n        -1.0,\\n        -1.0\\n      ],\\n      \\\"fold_params\\\": [\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n        \\n\\n... [截断: 输出过长，省略 15310 字符] ...\\n\\ngreedy\\\": {\\n      \\\"mean_diff\\\": 0.00877898725895342,\\n      \\\"ci_95\\\": [\\n        0.006656790922019183,\\n        0.010895566514062656\\n      ],\\n      \\\"p_value\\\": 0.0,\\n      \\\"significant\\\": true\\n    },\\n    \\\"bootstrap_construction_lp_weighted_cv_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.00877898725895342,\\n      \\\"ci_95\\\": [\\n        0.006656790922019183,\\n        0.010895566514062656\\n      ],\\n      \\\"p_value\\\": 0.0,\\n      \\\"significant\\\": true\\n    },\\n    \\\"adaptive_uniform\\\": {\\n      \\\"F1\\\": -1.0,\\n      \\\"std\\\": 0.0,\\n      \\\"fold_f1s\\\": [\\n        -1.0,\\n        -1.0,\\n        -1.0,\\n        -1.0,\\n        -1.0\\n      ],\\n      \\\"fold_params\\\": [\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        }\\n      ]\\n    },\\n    \\\"bootstrap_adaptive_uniform_vs_greedy\\\": {\\n      \\\"mean_diff\\\": -1.747846596585455,\\n      \\\"ci_95\\\": [\\n        -1.7515973904229796,\\n        -1.7441792858668868\\n      ],\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant\\\": false\\n    },\\n    \\\"lp_alignment_gating\\\": {\\n      \\\"dataset\\\": \\\"fewnerd\\\",\\n      \\\"mean_alignment\\\": 0.44033714923998635,\\n      \\\"median_alignment\\\": 0.606976978666884,\\n      \\\"frac_positive\\\": 0.7283279594656841,\\n      \\\"recommendation\\\": \\\"LP selection\\\"\\n    },\\n    \\\"sweep_uniform_t0.1\\\": {\\n      \\\"F1\\\": 0.676264516717343,\\n      \\\"theta\\\": 0.1\\n    },\\n    \\\"sweep_uniform_t0.15\\\": {\\n      \\\"F1\\\": 0.7510129759717606,\\n      \\\"theta\\\": 0.15\\n    },\\n    \\\"sweep_uniform_t0.2\\\": {\\n      \\\"F1\\\": 0.7510129759717606,\\n      \\\"theta\\\": 0.2\\n    },\\n    \\\"sweep_uniform_t0.25\\\": {\\n      \\\"F1\\\": 0.7510129759717606,\\n      \\\"theta\\\": 0.25\\n    },\\n    \\\"sweep_uniform_t0.3\\\": {\\n      \\\"F1\\\": 0.7499018949366549,\\n      \\\"theta\\\": 0.3\\n    },\\n    \\\"sweep_uniform_t0.35\\\": {\\n      \\\"F1\\\": 0.7499018949366549,\\n      \\\"theta\\\": 0.35\\n    },\\n    \\\"sweep_uniform_t0.4\\\": {\\n      \\\"F1\\\": 0.7277358122910127,\\n      \\\"theta\\\": 0.4\\n    },\\n    \\\"sweep_uniform_t0.45\\\": {\\n      \\\"F1\\\": 0.7277358122910127,\\n      \\\"theta\\\": 0.45\\n    },\\n    \\\"sweep_uniform_t0.5\\\": {\\n      \\\"F1\\\": 0.7277358122910127,\\n      \\\"theta\\\": 0.5\\n    },\\n    \\\"sweep_uniform_t0.55\\\": {\\n      \\\"F1\\\": 0.6823201127565961,\\n      \\\"theta\\\": 0.55\\n    },\\n    \\\"sweep_uniform_t0.6\\\": {\\n      \\\"F1\\\": 0.6823201127565961,\\n      \\\"theta\\\": 0.6\\n    },\\n    \\\"sweep_uniform_t0.7\\\": {\\n      \\\"F1\\\": 0.611199337918704,\\n      \\\"theta\\\": 0.7\\n    },\\n    \\\"sweep_uniform_t0.8\\\": {\\n      \\\"F1\\\": 0.498253792969909,\\n      \\\"theta\\\": 0.8\\n    },\\n    \\\"sweep_uniform_t0.9\\\": {\\n      \\\"F1\\\": 0.30545120402370285,\\n      \\\"theta\\\": 0.9\\n    },\\n    \\\"sweep_lp_weighted_t0.1\\\": {\\n      \\\"F1\\\": 0.6766447390096902,\\n      \\\"theta\\\": 0.1\\n    },\\n    \\\"sweep_lp_weighted_t0.15\\\": {\\n      \\\"F1\\\": 0.7510129759717606,\\n      \\\"theta\\\": 0.15\\n    },\\n    \\\"sweep_lp_weighted_t0.2\\\": {\\n      \\\"F1\\\": 0.7510129759717606,\\n      \\\"theta\\\": 0.2\\n    },\\n    \\\"sweep_lp_weighted_t0.25\\\": {\\n      \\\"F1\\\": 0.7566255838444086,\\n      \\\"theta\\\": 0.25\\n    },\\n    \\\"sweep_lp_weighted_t0.3\\\": {\\n      \\\"F1\\\": 0.7499018949366549,\\n      \\\"theta\\\": 0.3\\n    },\\n    \\\"sweep_lp_weighted_t0.35\\\": {\\n      \\\"F1\\\": 0.7498826023432166,\\n      \\\"theta\\\": 0.35\\n    },\\n    \\\"sweep_lp_weighted_t0.4\\\": {\\n      \\\"F1\\\": 0.7287704197628816,\\n      \\\"theta\\\": 0.4\\n    },\\n    \\\"sweep_lp_weighted_t0.45\\\": {\\n      \\\"F1\\\": 0.7277358122910127,\\n      \\\"theta\\\": 0.45\\n    },\\n    \\\"sweep_lp_weighted_t0.5\\\": {\\n      \\\"F1\\\": 0.725253680130052,\\n      \\\"theta\\\": 0.5\\n    },\\n    \\\"sweep_lp_weighted_t0.55\\\": {\\n      \\\"F1\\\": 0.6824137715927698,\\n      \\\"theta\\\": 0.55\\n    },\\n    \\\"sweep_lp_weighted_t0.6\\\": {\\n      \\\"F1\\\": 0.6823201127565961,\\n      \\\"theta\\\": 0.6\\n    },\\n    \\\"sweep_lp_weighted_t0.7\\\": {\\n      \\\"F1\\\": 0.611199337918704,\\n      \\\"theta\\\": 0.7\\n    },\\n    \\\"sweep_lp_weighted_t0.8\\\": {\\n      \\\"F1\\\": 0.4986082211603892,\\n      \\\"theta\\\": 0.8\\n    },\\n    \\\"sweep_lp_weighted_t0.9\\\": {\\n      \\\"F1\\\": 0.32283828470948245,\\n      \\\"theta\\\": 0.9\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.97}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "e97ff8d1-41b3-4867-9397-5db1da2f935f",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"scierc\\\\\\\": {\\\\n    \\\\\\\"greedy\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6439219990259687,\\\\n      \\\\\\\"std\\\\\\\": 0.30526978546327577\\\\n    },\\\\n    \\\\\\\"lp_selection\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6500718843902431,\\\\n      \\\\\\\"std\\\\\\\": 0.29705508172192924\\\\n    },\\\\n    \\\\\\\"sj_selection\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.5930517864827884,\\\\n      \\\\\\\"std\\\\\\\": 0.3373844979835319\\\\n    },\\\\n    \\\\\\\"oracle\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7758023559647044,\\\\n      \\\\\\\"std\\\\\\\": 0.253799245007122\\\\n    },\\\\n    \\\\\\\"random\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6090607200574826,\\\\n      \\\\\\\"std\\\\\\\": 0.25985586541169237\\\\n    },\\\\n    \\\\\\\"construction_uniform_majority\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.653641905167507,\\\\n      \\\\\\\"std\\\\\\\": 0.3010870867244481,\\\\n      \\\\\\\"theta\\\\\\\": 0.5\\\\n    },\\\\n    \\\\\\\"construction_uniform_confirm\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6593292957102236,\\\\n      \\\\\\\"std\\\\\\\": 0.2679778282300995,\\\\n      \\\\\\\"theta\\\\\\\": 0.25\\\\n    },\\\\n    \\\\\\\"construction_uniform_cv\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6552371710387132,\\\\n      \\\\\\\"std\\\\\\\": 0.0279304877311693,\\\\n      \\\\\\\"fold_f1s\\\\\\\": [\\\\n        0.6654736328751916,\\\\n        0.6439552062193571,\\\\n        0.6390221475404606,\\\\n        0.6235152164397447,\\\\n        0.7042196521188119\\\\n      ],\\\\n      \\\\\\\"fold_thetas\\\\\\\": [\\\\n        0.3,\\\\n        0.15,\\\\n        0.15,\\\\n        0.3,\\\\n        0.3\\\\n      ]\\\\n    },\\\\n    \\\\\\\"bootstrap_construction_uniform_majority_vs_greedy\\\\\\\": {\\\\n      \\\\\\\"mean_diff\\\\\\\": 0.009719906141538169,\\\\n      \\\\\\\"ci_95\\\\\\\": [\\\\n        -0.0025668807646749554,\\\\n        0.022544121575769724\\\\n      ],\\\\n      \\\\\\\"p_value\\\\\\\": 0.0652,\\\\n      \\\\\\\"significant\\\\\\\": false\\\\n    },\\\\n    \\\\\\\"bootstrap_construction_uniform_confirm_vs_greedy\\\\\\\": {\\\\n      \\\\\\\"mean_diff\\\\\\\": 0.015407296684254787,\\\\n      \\\\\\\"ci_95\\\\\\\": [\\\\n        0.0002982097298436904,\\\\n        0.031248574994734275\\\\n      ],\\\\n      \\\\\\\"p_value\\\\\\\": 0.0233,\\\\n      \\\\\\\"significant\\\\\\\": true\\\\n    },\\\\n    \\\\\\\"bootstrap_construction_uniform_cv_vs_greedy\\\\\\\": {\\\\n      \\\\\\\"mean_diff\\\\\\\": 0.011222577530551364,\\\\n      \\\\\\\"ci_95\\\\\\\": [\\\\n        -0.002930266201421545,\\\\n        0.026136005774118017\\\\n      ],\\\\n      \\\\\\\"p_value\\\\\\\": 0.0573,\\\\n      \\\\\\\"significant\\\\\\\": false\\\\n    },\\\\n    \\\\\\\"bootstrap_lp_selection_vs_greedy\\\\\\\": {\\\\n      \\\\\\\"mean_diff\\\\\\\": 0.006149885364274336,\\\\n      \\\\\\\"ci_95\\\\\\\": [\\\\n        -0.007718206771915206,\\\\n        0.01993277103717168\\\\n      ],\\\\n      \\\\\\\"p_value\\\\\\\": 0.193,\\\\n      \\\\\\\"significant\\\\\\\": false\\\\n    },\\\\n    \\\\\\\"construction_lp_weighted_majority\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6484769797757384,\\\\n      \\\\\\\"std\\\\\\\": 0.3065424667758378,\\\\n      \\\\\\\"theta\\\\\\\": 0.5\\\\n    },\\\\n    \\\\\\\"construction_lp_weighted_confirm\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6606099142231339,\\\\n      \\\\\\\"std\\\\\\\": 0.2803411122678887,\\\\n      \\\\\\\"theta\\\\\\\": 0.25\\\\n    },\\\\n    \\\\\\\"construction_lp_weighted_cv\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6565108240104793,\\\\n      \\\\\\\"std\\\\\\\": 0.02752929887287152,\\\\n      \\\\\\\"fold_f1s\\\\\\\": [\\\\n        0.6654736328751916,\\\\n        0.650323471078188,\\\\n        0.6390221475404606,\\\\n        0.6235152164397447,\\\\n        0.7042196521188119\\\\n      ],\\\\n      \\\\\\\"fold_thetas\\\\\\\": [\\\\n        0.3,\\\\n        0.25,\\\\n        0.15,\\\\n        0.3,\\\\n        0.3\\\\n      ]\\\\n    },\\\\n    \\\\\\\"bootstrap_construction_lp_weighted_majority_vs_greedy\\\\\\\": {\\\\n      \\\\\\\"mean_diff\\\\\\\": 0.004554980749769676,\\\\n      \\\\\\\"ci_95\\\\\\\": [\\\\n        -0.008595347655771845,\\\\n        0.0175267203869311\\\\n      ],\\\\n      \\\\\\\"p_value\\\\\\\": 0.2438,\\\\n      \\\\\\\"significant\\\\\\\": false\\\\n    },\\\\n    \\\\\\\"bootstrap_construction_lp_weighted_confirm_vs_greedy\\\\\\\": {\\\\n      \\\\\\\"mean_diff\\\\\\\": 0.016687915197165084,\\\\n      \\\\\\\"ci_95\\\\\\\": [\\\\n        0.003708882393845699,\\\\n        0.030250983686895105\\\\n      ],\\\\n      \\\\\\\"p_value\\\\\\\": 0.0044,\\\\n      \\\\\\\"significant\\\\\\\": true\\\\n    },\\\\n    \\\\\\\"bootstrap_construction_lp_weighted_cv_vs_greedy\\\\\\\": {\\\\n      \\\\\\\"mean_diff\\\\\\\": 0.01249863816388988,\\\\n      \\\\\\\"ci_95\\\\\\\": [\\\\n        -0.0008866984975969504,\\\\n        0.02678501619452975\\\\n      ],\\\\n      \\\\\\\"p_value\\\\\\\": 0.0351,\\\\n      \\\\\\\"significant\\\\\\\": true\\\\n    },\\\\n    \\\\\\\"adaptive_uniform\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": -1.0,\\\\n      \\\\\\\"std\\\\\\\": 0.0,\\\\n      \\\\\\\"fold_f1s\\\\\\\": [\\\\n        -1.0,\\\\n        -1.0,\\\\n        -1.0,\\\\n        -1.0,\\\\n        -1.0\\\\n      ],\\\\n      \\\\\\\"fold_params\\\\\\\": [\\\\n        {\\\\n          \\\\\\\"gate_threshold\\\\\\\": 0,\\\\n          \\\\\\\"construction_theta\\\\\\\": 0\\\\n        },\\\\n        {\\\\n          \\\\\\\"gate_threshold\\\\\\\": 0,\\\\n          \\\\\\\"construction_theta\\\\\\\": 0\\\\n        },\\\\n        {\\\\n          \\\\\\\"gate_threshold\\\\\\\": 0,\\\\n          \\\\\\\"construction_theta\\\\\\\": 0\\\\n        },\\\\n        {\\\\n          \\\\\\\"gate_threshold\\\\\\\": 0,\\\\n          \\\\\\\"construction_theta\\\\\\\": 0\\\\n        },\\\\n        {\\\\n          \\\\\\\"gate_threshold\\\\\\\": 0,\\\\n        \\\\n\\\\n... [截断: 输出过长，省略 15310 字符] ...\\\\n\\\\ngreedy\\\\\\\": {\\\\n      \\\\\\\"mean_diff\\\\\\\": 0.00877898725895342,\\\\n      \\\\\\\"ci_95\\\\\\\": [\\\\n        0.006656790922019183,\\\\n        0.010895566514062656\\\\n      ],\\\\n      \\\\\\\"p_value\\\\\\\": 0.0,\\\\n      \\\\\\\"significant\\\\\\\": true\\\\n    },\\\\n    \\\\\\\"bootstrap_construction_lp_weighted_cv_vs_greedy\\\\\\\": {\\\\n      \\\\\\\"mean_diff\\\\\\\": 0.00877898725895342,\\\\n      \\\\\\\"ci_95\\\\\\\": [\\\\n        0.006656790922019183,\\\\n        0.010895566514062656\\\\n      ],\\\\n      \\\\\\\"p_value\\\\\\\": 0.0,\\\\n      \\\\\\\"significant\\\\\\\": true\\\\n    },\\\\n    \\\\\\\"adaptive_uniform\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": -1.0,\\\\n      \\\\\\\"std\\\\\\\": 0.0,\\\\n      \\\\\\\"fold_f1s\\\\\\\": [\\\\n        -1.0,\\\\n        -1.0,\\\\n        -1.0,\\\\n        -1.0,\\\\n        -1.0\\\\n      ],\\\\n      \\\\\\\"fold_params\\\\\\\": [\\\\n        {\\\\n          \\\\\\\"gate_threshold\\\\\\\": 0,\\\\n          \\\\\\\"construction_theta\\\\\\\": 0\\\\n        },\\\\n        {\\\\n          \\\\\\\"gate_threshold\\\\\\\": 0,\\\\n          \\\\\\\"construction_theta\\\\\\\": 0\\\\n        },\\\\n        {\\\\n          \\\\\\\"gate_threshold\\\\\\\": 0,\\\\n          \\\\\\\"construction_theta\\\\\\\": 0\\\\n        },\\\\n        {\\\\n          \\\\\\\"gate_threshold\\\\\\\": 0,\\\\n          \\\\\\\"construction_theta\\\\\\\": 0\\\\n        },\\\\n        {\\\\n          \\\\\\\"gate_threshold\\\\\\\": 0,\\\\n          \\\\\\\"construction_theta\\\\\\\": 0\\\\n        }\\\\n      ]\\\\n    },\\\\n    \\\\\\\"bootstrap_adaptive_uniform_vs_greedy\\\\\\\": {\\\\n      \\\\\\\"mean_diff\\\\\\\": -1.747846596585455,\\\\n      \\\\\\\"ci_95\\\\\\\": [\\\\n        -1.7515973904229796,\\\\n        -1.7441792858668868\\\\n      ],\\\\n      \\\\\\\"p_value\\\\\\\": 1.0,\\\\n      \\\\\\\"significant\\\\\\\": false\\\\n    },\\\\n    \\\\\\\"lp_alignment_gating\\\\\\\": {\\\\n      \\\\\\\"dataset\\\\\\\": \\\\\\\"fewnerd\\\\\\\",\\\\n      \\\\\\\"mean_alignment\\\\\\\": 0.44033714923998635,\\\\n      \\\\\\\"median_alignment\\\\\\\": 0.606976978666884,\\\\n      \\\\\\\"frac_positive\\\\\\\": 0.7283279594656841,\\\\n      \\\\\\\"recommendation\\\\\\\": \\\\\\\"LP selection\\\\\\\"\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.1\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.676264516717343,\\\\n      \\\\\\\"theta\\\\\\\": 0.1\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.15\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7510129759717606,\\\\n      \\\\\\\"theta\\\\\\\": 0.15\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.2\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7510129759717606,\\\\n      \\\\\\\"theta\\\\\\\": 0.2\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.25\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7510129759717606,\\\\n      \\\\\\\"theta\\\\\\\": 0.25\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.3\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7499018949366549,\\\\n      \\\\\\\"theta\\\\\\\": 0.3\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.35\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7499018949366549,\\\\n      \\\\\\\"theta\\\\\\\": 0.35\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.4\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7277358122910127,\\\\n      \\\\\\\"theta\\\\\\\": 0.4\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.45\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7277358122910127,\\\\n      \\\\\\\"theta\\\\\\\": 0.45\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.5\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7277358122910127,\\\\n      \\\\\\\"theta\\\\\\\": 0.5\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.55\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6823201127565961,\\\\n      \\\\\\\"theta\\\\\\\": 0.55\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.6\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6823201127565961,\\\\n      \\\\\\\"theta\\\\\\\": 0.6\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.7\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.611199337918704,\\\\n      \\\\\\\"theta\\\\\\\": 0.7\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.8\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.498253792969909,\\\\n      \\\\\\\"theta\\\\\\\": 0.8\\\\n    },\\\\n    \\\\\\\"sweep_uniform_t0.9\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.30545120402370285,\\\\n      \\\\\\\"theta\\\\\\\": 0.9\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.1\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6766447390096902,\\\\n      \\\\\\\"theta\\\\\\\": 0.1\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.15\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7510129759717606,\\\\n      \\\\\\\"theta\\\\\\\": 0.15\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.2\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7510129759717606,\\\\n      \\\\\\\"theta\\\\\\\": 0.2\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.25\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7566255838444086,\\\\n      \\\\\\\"theta\\\\\\\": 0.25\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.3\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7499018949366549,\\\\n      \\\\\\\"theta\\\\\\\": 0.3\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.35\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7498826023432166,\\\\n      \\\\\\\"theta\\\\\\\": 0.35\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.4\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7287704197628816,\\\\n      \\\\\\\"theta\\\\\\\": 0.4\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.45\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.7277358122910127,\\\\n      \\\\\\\"theta\\\\\\\": 0.45\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.5\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.725253680130052,\\\\n      \\\\\\\"theta\\\\\\\": 0.5\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.55\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6824137715927698,\\\\n      \\\\\\\"theta\\\\\\\": 0.55\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.6\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.6823201127565961,\\\\n      \\\\\\\"theta\\\\\\\": 0.6\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.7\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.611199337918704,\\\\n      \\\\\\\"theta\\\\\\\": 0.7\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.8\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.4986082211603892,\\\\n      \\\\\\\"theta\\\\\\\": 0.8\\\\n    },\\\\n    \\\\\\\"sweep_lp_weighted_t0.9\\\\\\\": {\\\\n      \\\\\\\"F1\\\\\\\": 0.32283828470948245,\\\\n      \\\\\\\"theta\\\\\\\": 0.9\\\\n    }\\\\n  }\\\\n}\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.97}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"scierc\\\": {\\n    \\\"greedy\\\": {\\n      \\\"F1\\\": 0.6439219990259687,\\n      \\\"std\\\": 0.30526978546327577\\n    },\\n    \\\"lp_selection\\\": {\\n      \\\"F1\\\": 0.6500718843902431,\\n      \\\"std\\\": 0.29705508172192924\\n    },\\n    \\\"sj_selection\\\": {\\n      \\\"F1\\\": 0.5930517864827884,\\n      \\\"std\\\": 0.3373844979835319\\n    },\\n    \\\"oracle\\\": {\\n      \\\"F1\\\": 0.7758023559647044,\\n      \\\"std\\\": 0.253799245007122\\n    },\\n    \\\"random\\\": {\\n      \\\"F1\\\": 0.6090607200574826,\\n      \\\"std\\\": 0.25985586541169237\\n    },\\n    \\\"construction_uniform_majority\\\": {\\n      \\\"F1\\\": 0.653641905167507,\\n      \\\"std\\\": 0.3010870867244481,\\n      \\\"theta\\\": 0.5\\n    },\\n    \\\"construction_uniform_confirm\\\": {\\n      \\\"F1\\\": 0.6593292957102236,\\n      \\\"std\\\": 0.2679778282300995,\\n      \\\"theta\\\": 0.25\\n    },\\n    \\\"construction_uniform_cv\\\": {\\n      \\\"F1\\\": 0.6552371710387132,\\n      \\\"std\\\": 0.0279304877311693,\\n      \\\"fold_f1s\\\": [\\n        0.6654736328751916,\\n        0.6439552062193571,\\n        0.6390221475404606,\\n        0.6235152164397447,\\n        0.7042196521188119\\n      ],\\n      \\\"fold_thetas\\\": [\\n        0.3,\\n        0.15,\\n        0.15,\\n        0.3,\\n        0.3\\n      ]\\n    },\\n    \\\"bootstrap_construction_uniform_majority_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.009719906141538169,\\n      \\\"ci_95\\\": [\\n        -0.0025668807646749554,\\n        0.022544121575769724\\n      ],\\n      \\\"p_value\\\": 0.0652,\\n      \\\"significant\\\": false\\n    },\\n    \\\"bootstrap_construction_uniform_confirm_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.015407296684254787,\\n      \\\"ci_95\\\": [\\n        0.0002982097298436904,\\n        0.031248574994734275\\n      ],\\n      \\\"p_value\\\": 0.0233,\\n      \\\"significant\\\": true\\n    },\\n    \\\"bootstrap_construction_uniform_cv_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.011222577530551364,\\n      \\\"ci_95\\\": [\\n        -0.002930266201421545,\\n        0.026136005774118017\\n      ],\\n      \\\"p_value\\\": 0.0573,\\n      \\\"significant\\\": false\\n    },\\n    \\\"bootstrap_lp_selection_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.006149885364274336,\\n      \\\"ci_95\\\": [\\n        -0.007718206771915206,\\n        0.01993277103717168\\n      ],\\n      \\\"p_value\\\": 0.193,\\n      \\\"significant\\\": false\\n    },\\n    \\\"construction_lp_weighted_majority\\\": {\\n      \\\"F1\\\": 0.6484769797757384,\\n      \\\"std\\\": 0.3065424667758378,\\n      \\\"theta\\\": 0.5\\n    },\\n    \\\"construction_lp_weighted_confirm\\\": {\\n      \\\"F1\\\": 0.6606099142231339,\\n      \\\"std\\\": 0.2803411122678887,\\n      \\\"theta\\\": 0.25\\n    },\\n    \\\"construction_lp_weighted_cv\\\": {\\n      \\\"F1\\\": 0.6565108240104793,\\n      \\\"std\\\": 0.02752929887287152,\\n      \\\"fold_f1s\\\": [\\n        0.6654736328751916,\\n        0.650323471078188,\\n        0.6390221475404606,\\n        0.6235152164397447,\\n        0.7042196521188119\\n      ],\\n      \\\"fold_thetas\\\": [\\n        0.3,\\n        0.25,\\n        0.15,\\n        0.3,\\n        0.3\\n      ]\\n    },\\n    \\\"bootstrap_construction_lp_weighted_majority_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.004554980749769676,\\n      \\\"ci_95\\\": [\\n        -0.008595347655771845,\\n        0.0175267203869311\\n      ],\\n      \\\"p_value\\\": 0.2438,\\n      \\\"significant\\\": false\\n    },\\n    \\\"bootstrap_construction_lp_weighted_confirm_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.016687915197165084,\\n      \\\"ci_95\\\": [\\n        0.003708882393845699,\\n        0.030250983686895105\\n      ],\\n      \\\"p_value\\\": 0.0044,\\n      \\\"significant\\\": true\\n    },\\n    \\\"bootstrap_construction_lp_weighted_cv_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.01249863816388988,\\n      \\\"ci_95\\\": [\\n        -0.0008866984975969504,\\n        0.02678501619452975\\n      ],\\n      \\\"p_value\\\": 0.0351,\\n      \\\"significant\\\": true\\n    },\\n    \\\"adaptive_uniform\\\": {\\n      \\\"F1\\\": -1.0,\\n      \\\"std\\\": 0.0,\\n      \\\"fold_f1s\\\": [\\n        -1.0,\\n        -1.0,\\n        -1.0,\\n        -1.0,\\n        -1.0\\n      ],\\n      \\\"fold_params\\\": [\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n        \\n\\n... [截断: 输出过长，省略 15310 字符] ...\\n\\ngreedy\\\": {\\n      \\\"mean_diff\\\": 0.00877898725895342,\\n      \\\"ci_95\\\": [\\n        0.006656790922019183,\\n        0.010895566514062656\\n      ],\\n      \\\"p_value\\\": 0.0,\\n      \\\"significant\\\": true\\n    },\\n    \\\"bootstrap_construction_lp_weighted_cv_vs_greedy\\\": {\\n      \\\"mean_diff\\\": 0.00877898725895342,\\n      \\\"ci_95\\\": [\\n        0.006656790922019183,\\n        0.010895566514062656\\n      ],\\n      \\\"p_value\\\": 0.0,\\n      \\\"significant\\\": true\\n    },\\n    \\\"adaptive_uniform\\\": {\\n      \\\"F1\\\": -1.0,\\n      \\\"std\\\": 0.0,\\n      \\\"fold_f1s\\\": [\\n        -1.0,\\n        -1.0,\\n        -1.0,\\n        -1.0,\\n        -1.0\\n      ],\\n      \\\"fold_params\\\": [\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        },\\n        {\\n          \\\"gate_threshold\\\": 0,\\n          \\\"construction_theta\\\": 0\\n        }\\n      ]\\n    },\\n    \\\"bootstrap_adaptive_uniform_vs_greedy\\\": {\\n      \\\"mean_diff\\\": -1.747846596585455,\\n      \\\"ci_95\\\": [\\n        -1.7515973904229796,\\n        -1.7441792858668868\\n      ],\\n      \\\"p_value\\\": 1.0,\\n      \\\"significant\\\": false\\n    },\\n    \\\"lp_alignment_gating\\\": {\\n      \\\"dataset\\\": \\\"fewnerd\\\",\\n      \\\"mean_alignment\\\": 0.44033714923998635,\\n      \\\"median_alignment\\\": 0.606976978666884,\\n      \\\"frac_positive\\\": 0.7283279594656841,\\n      \\\"recommendation\\\": \\\"LP selection\\\"\\n    },\\n    \\\"sweep_uniform_t0.1\\\": {\\n      \\\"F1\\\": 0.676264516717343,\\n      \\\"theta\\\": 0.1\\n    },\\n    \\\"sweep_uniform_t0.15\\\": {\\n      \\\"F1\\\": 0.7510129759717606,\\n      \\\"theta\\\": 0.15\\n    },\\n    \\\"sweep_uniform_t0.2\\\": {\\n      \\\"F1\\\": 0.7510129759717606,\\n      \\\"theta\\\": 0.2\\n    },\\n    \\\"sweep_uniform_t0.25\\\": {\\n      \\\"F1\\\": 0.7510129759717606,\\n      \\\"theta\\\": 0.25\\n    },\\n    \\\"sweep_uniform_t0.3\\\": {\\n      \\\"F1\\\": 0.7499018949366549,\\n      \\\"theta\\\": 0.3\\n    },\\n    \\\"sweep_uniform_t0.35\\\": {\\n      \\\"F1\\\": 0.7499018949366549,\\n      \\\"theta\\\": 0.35\\n    },\\n    \\\"sweep_uniform_t0.4\\\": {\\n      \\\"F1\\\": 0.7277358122910127,\\n      \\\"theta\\\": 0.4\\n    },\\n    \\\"sweep_uniform_t0.45\\\": {\\n      \\\"F1\\\": 0.7277358122910127,\\n      \\\"theta\\\": 0.45\\n    },\\n    \\\"sweep_uniform_t0.5\\\": {\\n      \\\"F1\\\": 0.7277358122910127,\\n      \\\"theta\\\": 0.5\\n    },\\n    \\\"sweep_uniform_t0.55\\\": {\\n      \\\"F1\\\": 0.6823201127565961,\\n      \\\"theta\\\": 0.55\\n    },\\n    \\\"sweep_uniform_t0.6\\\": {\\n      \\\"F1\\\": 0.6823201127565961,\\n      \\\"theta\\\": 0.6\\n    },\\n    \\\"sweep_uniform_t0.7\\\": {\\n      \\\"F1\\\": 0.611199337918704,\\n      \\\"theta\\\": 0.7\\n    },\\n    \\\"sweep_uniform_t0.8\\\": {\\n      \\\"F1\\\": 0.498253792969909,\\n      \\\"theta\\\": 0.8\\n    },\\n    \\\"sweep_uniform_t0.9\\\": {\\n      \\\"F1\\\": 0.30545120402370285,\\n      \\\"theta\\\": 0.9\\n    },\\n    \\\"sweep_lp_weighted_t0.1\\\": {\\n      \\\"F1\\\": 0.6766447390096902,\\n      \\\"theta\\\": 0.1\\n    },\\n    \\\"sweep_lp_weighted_t0.15\\\": {\\n      \\\"F1\\\": 0.7510129759717606,\\n      \\\"theta\\\": 0.15\\n    },\\n    \\\"sweep_lp_weighted_t0.2\\\": {\\n      \\\"F1\\\": 0.7510129759717606,\\n      \\\"theta\\\": 0.2\\n    },\\n    \\\"sweep_lp_weighted_t0.25\\\": {\\n      \\\"F1\\\": 0.7566255838444086,\\n      \\\"theta\\\": 0.25\\n    },\\n    \\\"sweep_lp_weighted_t0.3\\\": {\\n      \\\"F1\\\": 0.7499018949366549,\\n      \\\"theta\\\": 0.3\\n    },\\n    \\\"sweep_lp_weighted_t0.35\\\": {\\n      \\\"F1\\\": 0.7498826023432166,\\n      \\\"theta\\\": 0.35\\n    },\\n    \\\"sweep_lp_weighted_t0.4\\\": {\\n      \\\"F1\\\": 0.7287704197628816,\\n      \\\"theta\\\": 0.4\\n    },\\n    \\\"sweep_lp_weighted_t0.45\\\": {\\n      \\\"F1\\\": 0.7277358122910127,\\n      \\\"theta\\\": 0.45\\n    },\\n    \\\"sweep_lp_weighted_t0.5\\\": {\\n      \\\"F1\\\": 0.725253680130052,\\n      \\\"theta\\\": 0.5\\n    },\\n    \\\"sweep_lp_weighted_t0.55\\\": {\\n      \\\"F1\\\": 0.6824137715927698,\\n      \\\"theta\\\": 0.55\\n    },\\n    \\\"sweep_lp_weighted_t0.6\\\": {\\n      \\\"F1\\\": 0.6823201127565961,\\n      \\\"theta\\\": 0.6\\n    },\\n    \\\"sweep_lp_weighted_t0.7\\\": {\\n      \\\"F1\\\": 0.611199337918704,\\n      \\\"theta\\\": 0.7\\n    },\\n    \\\"sweep_lp_weighted_t0.8\\\": {\\n      \\\"F1\\\": 0.4986082211603892,\\n      \\\"theta\\\": 0.8\\n    },\\n    \\\"sweep_lp_weighted_t0.9\\\": {\\n      \\\"F1\\\": 0.32283828470948245,\\n      \\\"theta\\\": 0.9\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.97}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 94_

<details><summary>Logged reasoning block</summary>

```text
Now I found the actual data source! The `entity_construction_fair_n8/multiseed_results.json` contains:

**FewNERD** (4 seeds: 42, 123, 456, 789):
- seed 42: greedy_f1 = 0.7478
- seed 123: greedy_f1 = 0.7480
- seed 456: greedy_f1 = 0.7486
- seed 789: greedy_f1 = 0.7478
- Mean: 0.7481

**SciERC** (3 seeds: 42, 123, 456):


- seed 42: greedy_f1 = 0.6439
- seed 123: greedy_f1 = 0.6457
- seed 456: greedy_f1 = 0.6478
- Mean: 0.6458

But there's a discrepancy—the α_crit table shows different seed sets than what's actually in the multiseed_results file, so I need to figure out which data is correct.

The FewNERD greedy_f1 values from entity_construction_fair_n8 are around 0.7478-0.7486, but the MF4v2 experiments show 0.7883—a massive ~4 percentage point gap that suggests the older data is using a different metric or pipeline. Looking closer, the "greedy_f1" field in entity_construction_fair_n8 actually corresponds to the macro-averaged F1 score from the seed 789 analysis.

json (0.7478), not micro-F1. The MF4v2 pipeline's greedy_f1 of 0.7883 is the true micro-F1 computed from aggregate TP/FP/FN counts, confirming this is the same macro-averaging bug. So the α_crit table definitely uses the macro-averaged F1 values, not micro-F1. Now I need to find which MF4v2 experiments have the correct micro-F1 data and pull those metrics to recompute the table.

Looking at what's available for FewNERD: seeds 42, 123, and 456 all have MF4v2 results with greedy_f1 values around 0.788-0.789. The registry shows seeds 42 and 123 are done, while seed 456 is still preparing. I need to check whether these MF4v2 reports actually contain the mv_f1 metric I need for the recomputation.

Checking the available metrics in the report.json files, I see greedy_f1, oracle_f1, and sample_f1_mean, but no mv_f1. This is a blocker since the α_crit table requires entity-level majority voting F1 scores. I need to hunt for analysis files that might contain these additional metrics like mv_f1, agreement rates, and degeneracy information. I'm noticing the greedy F1 value of 0.6483 from the old pipeline, and comparing it against the α_crit table which shows 0.6138 for SciERC MV—these don't match, so the table wasn't built directly from that report. I need to dig into the entity construction experiments and fair_results.json files to find where the majority voting F1 scores are actually computed, since they're not showing up in the standard report outputs. The FewNERD and CoNLL results are fairly consistent between old and new data, but SciERC is puzzling—the α_crit table references seeds 456 and 789, yet the multiseed data only contains seeds 42, 123, and 456, suggesting there's another data source I haven't located yet.

The real blocker is that I need the mv_f1 values to complete this analysis, and they're not in the standard report.json files, so I'm searching through the available analysis files to find where these cross-seed metrics might be stored.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "b7a003d8-b0c0-41bb-85d1-d0beb6a08a83",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GqHE3eBGs5UvzvwQdpZTNT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7198,
      "cache_read_input_tokens": 70712,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7198
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

_source line 95_

找到关键数据源。`entity_construction_fair_n8/multiseed_results.json` 显示 FewNERD greedy_f1 = 0.7478-0.7486（实际是 macro-F1），而 MF4v2 的 greedy_f1 = 0.7883（micro-F1）。差距约 4pp，确认受 bug 影响。

现在需要查找 MV F1 和其他 α_crit 所需指标。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "aa5daf65-40a8-44f2-80d4-11450b84c27e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GqHE3eBGs5UvzvwQdpZTNT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7198,
      "cache_read_input_tokens": 70712,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7198
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

_source line 96_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01SxNoxPjVQiS5nv4LW2QT2P`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output -maxdepth 2 -name \"*unified*\" -name \"*.json\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "2f0db583-0a87-41b0-8fbc-59237f5f7456",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GqHE3eBGs5UvzvwQdpZTNT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7198,
      "cache_read_input_tokens": 70712,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7198
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

_source line 97 · 2026-05-21T09:31:05.242Z_

<details><summary>↩ Tool result · `toolu_01SxNoxPjVQiS5nv4LW2QT2P`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_015_unified/exp015_unified_report.json\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round2/n8_seed123_unified_rho.json\\n/root/autodl-tmp/struct_self_consist_ie/output/analysis_unified_rho_full.json\\n/root/autodl-tmp/struct_self_consist_ie/output/d114_auroc_investigation/unified_auroc.json\\n/root/autodl-tmp/struct_self_consist_ie/output/exp_025_n32/unified_results.json\\n/root/autodl-tmp/struct_self_consist_ie/output/unified_tab_fewnerd_maxlp.json\\n/root/autodl-tmp/struct_self_consist_ie/output/unified_degeneracy_audit/unified_degeneracy_3def.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_multiseed_unified_v2.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "343405e7-fc3f-4c9a-b44f-c2c2ee728688",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/exp_015_unified/exp015_unified_report.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round2/n8_seed123_unified_rho.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/analysis_unified_rho_full.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/d114_auroc_investigation/unified_auroc.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/exp_025_n32/unified_results.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/unified_tab_fewnerd_maxlp.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/unified_degeneracy_audit/unified_degeneracy_3def.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_multiseed_unified_v2.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.36}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_015_unified/exp015_unified_report.json\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round2/n8_seed123_unified_rho.json\\n/root/autodl-tmp/struct_self_consist_ie/output/analysis_unified_rho_full.json\\n/root/autodl-tmp/struct_self_consist_ie/output/d114_auroc_investigation/unified_auroc.json\\n/root/autodl-tmp/struct_self_consist_ie/output/exp_025_n32/unified_results.json\\n/root/autodl-tmp/struct_self_consist_ie/output/unified_tab_fewnerd_maxlp.json\\n/root/autodl-tmp/struct_self_consist_ie/output/unified_degeneracy_audit/unified_degeneracy_3def.json\\n/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_multiseed_unified_v2.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 98_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_017J4aoG2V5KK5eCrTHXRpac`</summary>

```json
{
  "server": "autodl-5090",
  "command": "find /root/autodl-tmp/struct_self_consist_ie/output -name \"*claim_audit*\" -o -name \"*paper_f1*\" -o -name \"*recompute*\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "65816d03-87d4-4a6c-96c5-6a721a3976bb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GqHE3eBGs5UvzvwQdpZTNT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7198,
      "cache_read_input_tokens": 70712,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7198
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

_source line 99 · 2026-05-21T09:31:06.300Z_

<details><summary>↩ Tool result · `toolu_017J4aoG2V5KK5eCrTHXRpac`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/review_round2/recompute_re_selection.py\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round2/re_selection_recompute.json\\n/root/autodl-tmp/struct_self_consist_ie/output/recompute_tab_fewnerd_results.json\\n/root/autodl-tmp/struct_self_consist_ie/output/claim_audit\\n/root/autodl-tmp/struct_self_consist_ie/output/claim_audit/claim_audit_report.json\\n/root/autodl-tmp/struct_self_consist_ie/output/paper_f1_audit_script.py\\n/root/autodl-tmp/struct_self_consist_ie/output/paper_f1_audit\\n/root/autodl-tmp/struct_self_consist_ie/output/paper_f1_audit/paper_f1_audit_table.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "7e0d8d46-5f50-4e5f-9745-c5d48cf26cb9",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/struct_self_consist_ie/output/review_round2/recompute_re_selection.py\\\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round2/re_selection_recompute.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/recompute_tab_fewnerd_results.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/claim_audit\\\\n/root/autodl-tmp/struct_self_consist_ie/output/claim_audit/claim_audit_report.json\\\\n/root/autodl-tmp/struct_self_consist_ie/output/paper_f1_audit_script.py\\\\n/root/autodl-tmp/struct_self_consist_ie/output/paper_f1_audit\\\\n/root/autodl-tmp/struct_self_consist_ie/output/paper_f1_audit/paper_f1_audit_table.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.35}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/struct_self_consist_ie/output/review_round2/recompute_re_selection.py\\n/root/autodl-tmp/struct_self_consist_ie/output/review_round2/re_selection_recompute.json\\n/root/autodl-tmp/struct_self_consist_ie/output/recompute_tab_fewnerd_results.json\\n/root/autodl-tmp/struct_self_consist_ie/output/claim_audit\\n/root/autodl-tmp/struct_self_consist_ie/output/claim_audit/claim_audit_report.json\\n/root/autodl-tmp/struct_self_consist_ie/output/paper_f1_audit_script.py\\n/root/autodl-tmp/struct_self_consist_ie/output/paper_f1_audit\\n/root/autodl-tmp/struct_self_consist_ie/output/paper_f1_audit/paper_f1_audit_table.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 100_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01FpCVe98sWUQgrYsbvEuTNh`</summary>

```json
{
  "server": "autodl-5090",
  "command": "cat /root/autodl-tmp/struct_self_consist_ie/output/paper_f1_audit/paper_f1_audit_table.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "6986ae13-ffc9-44c1-9a46-461b58b60630",
  "uuid": "48b20f3e-5187-42b4-972a-4291c0291d95",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RFzEDE13t1fSr7GkA5BWJM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3580,
      "cache_read_input_tokens": 77910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3580
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
