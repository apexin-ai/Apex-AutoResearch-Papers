# cpu rho max verify

**When Self-Consistency Fails for NER: Degeneracy, Signal Collapse, and the Correlation-Selection Gap** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 49
- **Recorded user turns:** 0
- **Tool calls:** 17
- **Original source:** `logs/workers/worker_cpu_rho_max_verify_20260521T120007.log`
- **Structured JSON:** [`66ed1c7b0238b57005a9.json`](../../sessions/66/66ed1c7b0238b57005a9.json)

## Before a recorded user message

49 recorded events

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
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
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
  "uuid": "0904cef5-169c-4bda-8da7-6d0545198f20",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/memory/"
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
    "resetsAt": 1779382200,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "baa00788-cff1-4400-8472-bed6d83bf9a6",
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e"
}
```

---

### Assistant

_source line 4_

I'll investigate the Abstract's ρ claim and verify against actual experimental data.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "9ccc2181-750f-459b-9f46-d12b337ae4da",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018hTK59myCrvWHRPoSX2h6R",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11965
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_018NAEuURQjYRRSbQw3LUxka`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_registry",
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
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "38f48cf2-3135-45a0-90ad-25a84ae5c107",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018hTK59myCrvWHRPoSX2h6R",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11965,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11965
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

_source line 6 · 2026-05-21T12:00:19.907Z_

<details><summary>↩ Tool result · `toolu_018NAEuURQjYRRSbQw3LUxka`</summary>

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
  "tool_name": "mcp__agent-ml-research__read_registry"
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
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "2ada0d25-a749-4453-ab07-73d6197a332d",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_registry",
    "total_deferred_tools": 25
  }
}
```

</details>

---

### Assistant

_source line 7_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the Abstract source file and searching for ρ values, while also reading the registry and relevant data files in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "07b56d2d-15c7-420c-bd84-8f9f9f725cff",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A4jCnd8Nv8q6AJUcLU42WM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 800,
      "cache_read_input_tokens": 23806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 800
      },
      "output_tokens": 30,
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

_source line 8_

Let me gather the data in parallel: the paper source, experimental registry, and correlation data files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "ccd4f741-451f-4bda-a5dd-a32f50457c9b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A4jCnd8Nv8q6AJUcLU42WM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 800,
      "cache_read_input_tokens": 23806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 800
      },
      "output_tokens": 30,
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

<details open><summary>🔧 Tool call — Glob · `toolu_01XAS6R1JhSV1EokEnEzFH95`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "c5f86ff7-a9cd-4939-a59f-93632e3a27b4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A4jCnd8Nv8q6AJUcLU42WM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 800,
      "cache_read_input_tokens": 23806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 800
      },
      "output_tokens": 30,
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

_source line 10 · 2026-05-21T12:00:24.996Z_

<details><summary>↩ Tool result · `toolu_01XAS6R1JhSV1EokEnEzFH95`</summary>

```text
artifacts/dream_reports/dream_20260514T093336/best/paper.tex
artifacts/dream_reports/dream_20260514T093336/median/paper.tex
artifacts/dream_reports/dream_20260514T093336/worst/paper.tex
artifacts/dream_reports/dream_20260514T105303/best/paper.tex
artifacts/dream_reports/dream_20260514T105303/median/paper.tex
artifacts/dream_reports/dream_20260514T105303/worst/paper.tex
artifacts/_project/paper/related_work.tex
artifacts/dream_reports/dream_20260514T203201/best/paper.tex
artifacts/dream_reports/dream_20260514T203201/median/paper.tex
artifacts/dream_reports/dream_20260514T203201/worst/paper.tex
artifacts/bootstrap_ci_tables.tex
artifacts/dream_reports/dream_20260515T092545/best/paper.tex
artifacts/dream_reports/dream_20260515T092545/median/paper.tex
artifacts/dream_reports/dream_20260515T092545/worst/paper.tex
artifacts/_project/paper/freeform_ablation_appendix_table.tex
artifacts/freeform_ablation_appendix_table.tex
artifacts/_project/paper/n_scaling_appendix_tables_44b000.tex
artifacts/n_scaling_appendix_tables.tex
artifacts/_project/paper/method.tex
artifacts/_project/paper/n_scaling_appendix_tables.tex
artifacts/_project/paper/introduction.tex
artifacts/_project/paper/discussion.tex
artifacts/_project/paper/limitations.tex
artifacts/_project/paper/conclusion.tex
artifacts/_project/paper/abstract.tex
artifacts/_project/paper/experiments.tex
artifacts/dream_reports/dream_20260516T092241/best/paper.tex
artifacts/dream_reports/dream_20260516T092241/median/paper.tex
artifacts/dream_reports/dream_20260516T092241/worst/paper.tex
artifacts/dream_reports/dream_20260516T113255/best/paper.tex
artifacts/dream_reports/dream_20260516T113255/median/paper.tex
artifacts/dream_reports/dream_20260516T113255/worst/paper.tex
artifacts/per_type_lp_table.tex
artifacts/exp_021_fewnerd_full/paper/per_type_lp_table.tex
docs/paper/sections/checklist.tex
code/scale_table.tex
paper/sections/zeroshot_scaling_draft.tex
artifacts/_project/paper/scaling_narrative_A_monotonic.tex
artifacts/_project/paper/scaling_narrative_B_nonmonotonic.tex
artifacts/scaling_narrative_B_nonmonotonic.tex
artifacts/scaling_narrative_A_monotonic.tex
artifacts/exp_qwen25_72b_fewshot/paper/zs_vs_fs_comparison_draft.tex
artifacts/zs_vs_fs_comparison_draft.tex
artifacts/exp_qwen25_72b_fewshot/paper/tab_72b_zs_vs_fs_appendix.tex
artifacts/tab_72b_zs_vs_fs_appendix.tex
artifacts/_project/paper/theorem.tex
artifacts/p_impossibility/theorem.tex
docs/paper/sections/method.tex
docs/paper/sections/theoretical.tex
docs/paper/sections/diagnostic.tex
docs/paper/sections/experiments.tex
artifacts/r25_response/power_analysis.tex
artifacts/r25_response/holm_bonferroni_enumeration.tex
artifacts/r25_response/entity_independence_paragraph.tex
docs/paper/sections/related_work.tex
docs/paper/sections/abstract.tex
docs/paper/sections/single_signal.tex
docs/paper/sections/mechanistic.tex
docs/paper/sections/experiments_main.tex
docs/paper/sections/adaptive.tex
docs/paper/sections/introduction.tex
docs/paper/sections/limitations.tex
docs/paper/main.tex
docs/paper/sections/discussion.tex
docs/paper/sections/background.tex
docs/paper/sections/conclusion.tex
artifacts/_project/paper/e5_hyperparam_tables.tex
artifacts/e5_hyperparam_tables.tex
docs/paper/sections/theory.tex
artifacts/_project/paper/theory.tex
docs/paper/sections/appendix.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "1c5e9f8b-c99b-42c0-af23-d0bfcaee274e",
  "tool_use_result": {
    "filenames": [
      "artifacts/dream_reports/dream_20260514T093336/best/paper.tex",
      "artifacts/dream_reports/dream_20260514T093336/median/paper.tex",
      "artifacts/dream_reports/dream_20260514T093336/worst/paper.tex",
      "artifacts/dream_reports/dream_20260514T105303/best/paper.tex",
      "artifacts/dream_reports/dream_20260514T105303/median/paper.tex",
      "artifacts/dream_reports/dream_20260514T105303/worst/paper.tex",
      "artifacts/_project/paper/related_work.tex",
      "artifacts/dream_reports/dream_20260514T203201/best/paper.tex",
      "artifacts/dream_reports/dream_20260514T203201/median/paper.tex",
      "artifacts/dream_reports/dream_20260514T203201/worst/paper.tex",
      "artifacts/bootstrap_ci_tables.tex",
      "artifacts/dream_reports/dream_20260515T092545/best/paper.tex",
      "artifacts/dream_reports/dream_20260515T092545/median/paper.tex",
      "artifacts/dream_reports/dream_20260515T092545/worst/paper.tex",
      "artifacts/_project/paper/freeform_ablation_appendix_table.tex",
      "artifacts/freeform_ablation_appendix_table.tex",
      "artifacts/_project/paper/n_scaling_appendix_tables_44b000.tex",
      "artifacts/n_scaling_appendix_tables.tex",
      "artifacts/_project/paper/method.tex",
      "artifacts/_project/paper/n_scaling_appendix_tables.tex",
      "artifacts/_project/paper/introduction.tex",
      "artifacts/_project/paper/discussion.tex",
      "artifacts/_project/paper/limitations.tex",
      "artifacts/_project/paper/conclusion.tex",
      "artifacts/_project/paper/abstract.tex",
      "artifacts/_project/paper/experiments.tex",
      "artifacts/dream_reports/dream_20260516T092241/best/paper.tex",
      "artifacts/dream_reports/dream_20260516T092241/median/paper.tex",
      "artifacts/dream_reports/dream_20260516T092241/worst/paper.tex",
      "artifacts/dream_reports/dream_20260516T113255/best/paper.tex",
      "artifacts/dream_reports/dream_20260516T113255/median/paper.tex",
      "artifacts/dream_reports/dream_20260516T113255/worst/paper.tex",
      "artifacts/per_type_lp_table.tex",
      "artifacts/exp_021_fewnerd_full/paper/per_type_lp_table.tex",
      "docs/paper/sections/checklist.tex",
      "code/scale_table.tex",
      "paper/sections/zeroshot_scaling_draft.tex",
      "artifacts/_project/paper/scaling_narrative_A_monotonic.tex",
      "artifacts/_project/paper/scaling_narrative_B_nonmonotonic.tex",
      "artifacts/scaling_narrative_B_nonmonotonic.tex",
      "artifacts/scaling_narrative_A_monotonic.tex",
      "artifacts/exp_qwen25_72b_fewshot/paper/zs_vs_fs_comparison_draft.tex",
      "artifacts/zs_vs_fs_comparison_draft.tex",
      "artifacts/exp_qwen25_72b_fewshot/paper/tab_72b_zs_vs_fs_appendix.tex",
      "artifacts/tab_72b_zs_vs_fs_appendix.tex",
      "artifacts/_project/paper/theorem.tex",
      "artifacts/p_impossibility/theorem.tex",
      "docs/paper/sections/method.tex",
      "docs/paper/sections/theoretical.tex",
      "docs/paper/sections/diagnostic.tex",
      "docs/paper/sections/experiments.tex",
      "artifacts/r25_response/power_analysis.tex",
      "artifacts/r25_response/holm_bonferroni_enumeration.tex",
      "artifacts/r25_response/entity_independence_paragraph.tex",
      "docs/paper/sections/related_work.tex",
      "docs/paper/sections/abstract.tex",
      "docs/paper/sections/single_signal.tex",
      "docs/paper/sections/mechanistic.tex",
      "docs/paper/sections/experiments_main.tex",
      "docs/paper/sections/adaptive.tex",
      "docs/paper/sections/introduction.tex",
      "docs/paper/sections/limitations.tex",
      "docs/paper/main.tex",
      "docs/paper/sections/discussion.tex",
      "docs/paper/sections/background.tex",
      "docs/paper/sections/conclusion.tex",
      "artifacts/_project/paper/e5_hyperparam_tables.tex",
      "artifacts/e5_hyperparam_tables.tex",
      "docs/paper/sections/theory.tex",
      "artifacts/_project/paper/theory.tex",
      "docs/paper/sections/appendix.tex"
    ],
    "durationMs": 105,
    "numFiles": 71,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01SQo5pWHJQGQjgSe4xXkffP`</summary>

```json
{
  "project": "struct_self_consist_ie",
  "filters": {
    "status": "DONE"
  },
  "fields": [
    "*"
  ],
  "limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "86d412e7-eb5d-4c1e-a2ff-39f1a2b12cc3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A4jCnd8Nv8q6AJUcLU42WM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 800,
      "cache_read_input_tokens": 23806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 800
      },
      "output_tokens": 30,
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

<details open><summary>🔧 Tool call — Glob · `toolu_01ML6JcnxbZVuGGnnV1tAe8N`</summary>

```json
{
  "pattern": "**/*alpha*",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "0df5c0fc-7bfe-4626-8dc7-75c4d1487e63",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A4jCnd8Nv8q6AJUcLU42WM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 800,
      "cache_read_input_tokens": 23806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 800
      },
      "output_tokens": 30,
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

_source line 13 · 2026-05-21T12:00:27.178Z_

<details><summary>↩ Tool result · `toolu_01SQo5pWHJQGQjgSe4xXkffP`</summary>

```text
Error: result (412,003 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/ae3cc154-f589-46df-b165-661b1879021e/tool-results/mcp-agent-ml-research-read_registry-1779364827161.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/ae3cc154-f589-46df-b165-661b1879021e/tool-results/mcp-agent-ml-research-read_registry-1779364827161.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/ae3cc154-f589-46df-b165-661b1879021e/tool-results/mcp-agent-ml-research-read_registry-1779364827161.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "bf9dd358-ccc8-468e-a24f-3994b875a523",
  "tool_use_result": {
    "content": "Error: result (412,003 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/ae3cc154-f589-46df-b165-661b1879021e/tool-results/mcp-agent-ml-research-read_registry-1779364827161.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/ae3cc154-f589-46df-b165-661b1879021e/tool-results/mcp-agent-ml-research-read_registry-1779364827161.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/ae3cc154-f589-46df-b165-661b1879021e/tool-results/mcp-agent-ml-research-read_registry-1779364827161.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"exp_conll_n16_s42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-21T03:11:59.589Z\", \"updated_at\": \"2026-05-21T11:59:01.943Z\", \"hypothesis\": \"CoNLL N=16 seed=42: third seed completing 3-seed N=16 set. Tests whether high-degeneracy regime (60%+ at N=8) changes at N=16 — if degeneracy drops, additional samples may help; if persists, confirms structural ceiling.\", \"completed_at\": \"2026-05-21T04:24:19.862Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.908, \"oracle_f1\": 0.959, \"rho_SJ_full\": 0.446, \"rho_FK_full\": 0.427, \"rho_advantage\": 0.019, \"oracle_headroom\": 0.051, \"degeneracy_pct\": 7.8, \"verdict\": \"PASS\"}}}, \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/conll_n16_s42/\", \"server\": \"autodl-5090-c\", \"gpu\": [\"cuda:2\"], \"pid\": \"312281\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s42.log\", \"submitted_at\": \"2026-05-21T11:24:02.614Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/conll2003/\", \"data_count\": 0, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42, \"checkpoint_path\": \"output/conll_n16_s42/\", \"wall_clock_seconds\": 2099.3, \"gpu_hours\": 0.58}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.908, \"oracle_f1\": 0.9592, \"oracle_headroom\": 0.0512, \"fleiss_kappa\": 0.762, \"soft_jaccard\": 0.8844, \"n_instances\": 3453, \"rho_fk\": 0.4222, \"rho_sj\": 0.4414, \"rho_lp\": 0.3144, \"structural_beats_surface\": true}}, \"exp_fewnerd_n16_s456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T07:18:11.587Z\", \"updated_at\": \"2026-05-21T11:30:16.054Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/fewnerd_n16_seed456_v2/\\\"\", \"server\": \"autodl-5090-c\", \"gpu\": [\"cuda:0\"], \"pid\": \"293438\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_fewnerd_n16_s456_v2.log\", \"submitted_at\": \"2026-05-21T07:18:10.938Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/fewnerd/\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances, N=16)\", \"checkpoint_path\": \"output/fewnerd_n16_seed456_v2/\", \"wall_clock_seconds\": 15125.1, \"gpu_hours\": 4.2}, \"hypothesis\": \"FewNERD N=16 (seed=456, v2 rerun): data lost in previous run. Extending N-scaling curve to N=16 for Qwen3-8B-FT, critical for F1(N)=a-b*N^(-c) scaling law. Third seed for 3-seed statistical power.\", \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.7883, \"oracle_f1\": 0.9058, \"oracle_headroom\": 0.1175, \"fleiss_kappa\": 0.4552, \"rho_sj_full\": 0.285, \"rho_fk_full\": 0.233, \"samples_count\": 37648, \"mv_f1\": \"NOT_COMPUTED\", \"degeneracy_rate\": \"NOT_COMPUTED\", \"note\": \"report.json lacks mv_f1 and degeneracy; need post-processing from samples.jsonl\"}, \"completed_at\": \"2026-05-21T11:30:16.054Z\"}, \"exp_scierc_n16_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:42.345Z\", \"updated_at\": \"2026-05-21T11:22:22.613Z\", \"hypothesis\": \"SciERC N=16 seed 123: second seed at N=16 tests variance of scaling behavior and confirms whether the N=8→N=16 gains observed with seed 42 (exp-001) are robust across random seeds.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/scierc_n16_seed123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"data/scierc/processed_data/\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123}, \"log_path\": \"logs/scierc_n16_seed123.log\", \"checkpoint_path\": \"output/scierc_n16_seed123/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:44:30.424Z\"}, \"exp_14b_inference_conll_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T10:42:21.744Z\", \"updated_at\": \"2026-05-21T11:22:19.979Z\", \"hypothesis\": \"14B CoNLL rerun: Qwen2.5-14B fine-tuned model (qwen25-14b-fewnerd-merged-final) on CoNLL NER inference N=8 T=1.0. Previous run (exp_14b_inference_conll) crashed at 55% with EngineDeadError on 5090-b. Tests whether 14B scale preserves correlation-selection gap pattern on CoNLL.\", \"parent\": \"exp_14b_inference_conll\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen25-14b-fewnerd-merged-final --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/14b_conll_v2/ --gpu_memory_utilization 0.95 --enforce_eager\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen25-14b-fewnerd-merged-final\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/qwen25-14b-fewnerd-merged-final\", \"eval_data\": \"conll2003\", \"checkpoint_path\": \"output/14b_conll_v2/\", \"log_path\": \"output/14b_conll_v2_run.log\"}, \"conclusion\": \"failed\", \"metrics\": {\"greedy_f1\": 0.0462, \"oracle_f1\": 0.1549, \"sample_f1_zero_pct\": 95.2, \"fleiss_kappa\": 0.3712, \"soft_jaccard\": 0.658, \"rho_sj_full\": -0.27, \"structural_beats_surface\": false, \"verdict\": \"FAIL — 14B model fine-tuned on FewNERD cannot do CoNLL NER (cross-domain mismatch)\"}, \"completed_at\": \"2026-05-21T11:22:19.979Z\"}, \"exp_conll_mf4_v2_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T10:17:06.386Z\", \"updated_at\": \"2026-05-21T11:19:54.991Z\", \"hypothesis\": \"MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=42 using run_mvp_pilot.py (greedy_f1/micro-F1). Third seed completing 3-seed set for statistical power. α_crit noted only 2-seed for CoNLL.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/conll_mf4v2_seed42/\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42, \"checkpoint_path\": \"output/conll_mf4v2_seed42/\", \"log_path\": \"/tmp/exp_conll_mf4_v2_s42.log\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.9075, \"mv_f1\": 0.909, \"oracle_f1\": 0.9495, \"mv_gain_pp\": 0.15, \"degeneracy_rate\": 0.657, \"fleiss_kappa\": 0.7729, \"soft_jaccard\": 0.8949, \"alpha_crit\": 0.8332, \"alpha_crit_eff\": 2.4321, \"agreement_rho\": 0.424, \"samples_count\": 3453, \"verdict\": \"PASS\"}, \"completed_at\": \"2026-05-21T10:55:03.879Z\"}, \"exp_frontier_sc_gemini25pro\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T06:50:24.793Z\", \"updated_at\": \"2026-05-21T11:19:52.427Z\", \"hypothesis\": \"Frontier model Gemini 2.5 Pro on FewNERD SC (200 inst, N=8, T=1.0): 4-family cross-validation. If correlation-selection gap persists across GPT + Claude + Gemini + DeepSeek, the finding is universal.\", \"spec\": {\"command\": \"python -u code/run_frontier_sc.py --model google/gemini-2.5-pro --base_url http://47.94.22.126/v1 --dataset fewnerd --n_instances 200 --n_samples 8 --temperature 1.0 --output_dir output/frontier_sc_gemini25pro/ --max_workers 4\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 200, \"model_name\": \"google/gemini-2.5-pro\", \"seed\": 42, \"checkpoint_path\": \"output/frontier_sc_gemini25pro/\", \"log_path\": \"output/frontier_sc_gemini25pro/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.6301, \"mv_f1\": 0.6446, \"oracle_f1\": 0.7575, \"mv_gain_pp\": 1.45, \"selection_gap_pp\": 11.29, \"mv_captures_pct\": 11.4, \"agreement_rho\": 0.3887, \"degeneracy_rate\": 0.285, \"fleiss_kappa\": 0.5185, \"soft_jaccard\": 0.8023, \"alpha_crit\": 0.4756, \"alpha_crit_eff\": 0.6651, \"parse_failure_rate\": 0.119, \"n_instances\": 200, \"mv_wins\": 33, \"mv_ties\": 144, \"mv_loses\": 23, \"verdict\": \"MV helps (+1.45pp), captures 11% of oracle headroom\"}, \"completed_at\": \"2026-05-21T10:55:06.757Z\"}, \"exp_e2_pretrained_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T07:18:21.189Z\", \"updated_at\": \"2026-05-21T10:57:52.364Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path /root/autodl-tmp/.hf_cache/Qwen2.5-7B-Instruct/ --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/e2_pretrained_scierc/\\\"\", \"server\": \"autodl-5090-c\", \"gpu\": [\"cuda:3\"], \"pid\": \"294269\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_e2_pretrained_scierc.log\", \"submitted_at\": \"2026-05-21T07:18:20.538Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data/\", \"data_count\": 100, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"pretrained_base\", \"eval_data\": \"scierc test set (100 instances, N=8)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/e2_pretrained_scierc/\", \"wall_clock_seconds\": 6705.7, \"gpu_hours\": 1.86}, \"hypothesis\": \"Pre-trained Qwen2.5-7B-Instruct (no fine-tuning) on SciERC NER exhibits correlation-selection gap similar to fine-tuned models, demonstrating the gap is model-intrinsic rather than fine-tuning-induced.\", \"conclusion\": \"negative\", \"metrics\": {\"greedy_f1\": 0.2418, \"oracle_f1\": 0.3888, \"oracle_headroom\": 0.147, \"fleiss_kappa_mean\": 0.223, \"soft_jaccard_mean\": 0.473, \"rho_SJ_full\": 0.2193, \"rho_kappa_full\": 0.2516, \"rho_SJ_cond\": 0.1987, \"rho_kappa_cond\": 0.1953, \"logprob_rho_full\": 0.078, \"logprob_auroc_full\": 0.5412, \"logprob_rho_cond\": 0.1895, \"logprob_auroc_cond\": 0.5527, \"sample_f1_mean\": 0.2272, \"sample_f1_pct_zero\": 46.29, \"structural_beats_surface\": false, \"verdict\": \"FAIL\", \"warning\": \">30% samples F1=0\"}, \"checkpoint_path\": \"output/e2_pretrained_scierc/\", \"completed_at\": \"2026-05-21T09:10:06.217Z\"}, \"exp_e2_pretrained_conll\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:52:08.180Z\", \"updated_at\": \"2026-05-21T10:57:51.130Z\", \"hypothesis\": \"Pre-trained Qwen2.5-7B-Instruct (no fine-tuning) on CoNLL NER exhibits correlation-selection gap similar to fine-tuned models, demonstrating the gap is model-intrinsic rather than fine-tuning-induced.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path /root/autodl-tmp/models/Qwen2.5-7B-Instruct/Qwen/Qwen2___5-7B-Instruct --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/e2_pretrained_conll/\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"7939\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp_e2_pretrained_conll.log\", \"submitted_at\": \"2026-05-21T06:59:13.431Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"pretrained_base\", \"eval_data\": \"conll2003\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/e2_pretrained_conll/\", \"wall_clock_seconds\": 5840.6, \"gpu_hours\": 1.62}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T08:36:34.020Z\"}, \"exp_scierc_mf4_v2_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T09:01:28.521Z\", \"updated_at\": \"2026-05-21T10:55:22.891Z\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/scierc_mf4v2_seed42/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"18393\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_scierc_mf4_v2_s42.log\", \"submitted_at\": \"2026-05-21T09:08:39.861Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 529, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"output/scierc_mf4v2_seed42/\", \"wall_clock_seconds\": 6403.0, \"gpu_hours\": 1.78}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.6651, \"oracle_f1\": 0.7815, \"fleiss_kappa\": 0.4026, \"soft_jaccard\": 0.7075, \"oracle_headroom\": 0.1164, \"structural_beats_surface\": true, \"logprob_rho_full\": 0.2098, \"verdict\": \"MARGINAL\"}, \"hypothesis\": \"MF4v2 pipeline (N=8, T=1.0, logprobs) on SciERC with seed 42 produces consistent SC diagnostic signals (structural agreement > logprob baseline for quality estimation), validating cross-seed stability of the structured self-consistency framework on scientific NER.\", \"completed_at\": \"2026-05-21T10:55:22.891Z\"}, \"exp_fewnerd_mf4v2_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T10:16:50.798Z\", \"updated_at\": \"2026-05-21T10:18:44.434Z\", \"spec\": {\"server\": \"autodl-5090\", \"data_path\": \"data/fewnerd/\", \"data_count\": 32565, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 456, \"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/fewnerd_mf4v2_seed456/\"}, \"checkpoint_path\": \"output/fewnerd_mf4v2_seed456/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_fewnerd_mf4v2_s456.log\", \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.7889, \"oracle_f1\": 0.881, \"oracle_headroom\": 0.0921, \"fleiss_kappa_mean\": 0.3557, \"soft_jaccard_mean\": 0.6848, \"sample_f1_mean\": 0.6435, \"rho_softjaccard_full\": 0.3133, \"rho_fleiss_full\": 0.1647, \"rho_logprob_full\": 0.245, \"verdict\": \"MARGINAL\"}, \"hypothesis\": \"MF4v2 pipeline (N=8, T=1.0, logprobs) on FewNERD with seed 456 produces consistent SC diagnostic signals (structural agreement > logprob baseline for quality estimation), validating cross-seed stability of the structured self-consistency framework on fine-grained NER.\", \"completed_at\": \"2026-05-21T10:18:44.434Z\"}, \"exp_scierc_mf4_v2_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T09:28:19.668Z\", \"updated_at\": \"2026-05-21T10:18:41.541Z\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 8 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/scierc_mf4v2_seed456/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"20216\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_scierc_mf4_v2_s456.log\", \"submitted_at\": \"2026-05-21T09:28:18.878Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 529, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"wall_clock_seconds\": 3022.7, \"gpu_hours\": 0.84}, \"checkpoint_path\": \"output/scierc_mf4v2_seed456/\", \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.6631, \"oracle_f1\": 0.7732, \"oracle_headroom\": 0.1101, \"fleiss_kappa_mean\": 0.3885, \"soft_jaccard_mean\": 0.6945, \"sample_f1_mean\": 0.6061, \"rho_softjaccard_full\": 0.3756, \"rho_fleiss_full\": 0.2832, \"rho_logprob_full\": 0.2184, \"verdict\": \"MARGINAL\"}, \"hypothesis\": \"MF4v2 pipeline (N=8, T=1.0, logprobs) on SciERC with seed 456 produces consistent SC diagnostic signals (structural agreement > logprob baseline for quality estimation), validating cross-seed stability of the structured self-consistency framework on scientific NER.\", \"completed_at\": \"2026-05-21T10:18:41.541Z\"}, \"exp_scierc_mf4_v2_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T09:28:16.909Z\", \"updated_at\": \"2026-05-21T10:18:38.627Z\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 8 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/scierc_mf4v2_seed123/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"20074\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_scierc_mf4_v2_s123.log\", \"submitted_at\": \"2026-05-21T09:28:16.177Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 529, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"wall_clock_seconds\": 3022.4, \"gpu_hours\": 0.84}, \"checkpoint_path\": \"output/scierc_mf4v2_seed123/\", \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.6633, \"oracle_f1\": 0.7777, \"oracle_headroom\": 0.1144, \"fleiss_kappa_mean\": 0.3754, \"soft_jaccard_mean\": 0.6977, \"sample_f1_mean\": 0.6079, \"rho_softjaccard_full\": 0.3681, \"rho_fleiss_full\": 0.2457, \"rho_logprob_full\": 0.2209, \"verdict\": \"MARGINAL\"}, \"hypothesis\": \"MF4v2 pipeline (N=8, T=1.0, logprobs) on SciERC with seed 123 produces consistent SC diagnostic signals (structural agreement > logprob baseline for quality estimation), validating cross-seed stability of the structured self-consistency framework on scientific NER.\", \"completed_at\": \"2026-05-21T10:18:38.627Z\"}, \"exp_b1_scd\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:12:48.805Z\", \"updated_at\": \"2026-05-21T10:17:14.946Z\", \"hypothesis\": \"Self-Consistency Distillation via theta2n construction pseudo-labels can teach Qwen3-8B-FT to internalize SC benefits: after iterative SCD (M0→M1→M2→M3), greedy F1 should approach N=8 construction F1 (FewNERD target: 0.764 vs current greedy 0.748). CoNLL serves as negative control (construction Δ=-0.4pp, SCD should not help). Transductive setting: pseudo-labels from test set SC outputs.\", \"conclusion\": \"killed\", \"spec\": {\"command\": \"cancelled by Director\", \"server\": \"none\", \"data_path\": \"n/a\", \"data_count\": 0, \"model_name\": \"n/a\", \"seed\": 0, \"checkpoint_path\": \"n/a\", \"log_path\": \"n/a\", \"kill_reason\": \"Director cancelled - experiment no longer aligned with current research direction\"}, \"completed_at\": \"2026-05-21T10:17:14.946Z\"}, \"exp_fewnerd_mf4_v2_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:34:07.139Z\", \"updated_at\": \"2026-05-21T10:10:07.222Z\", \"hypothesis\": \"MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). Third seed completing 3-seed set for statistical power.\", \"spec\": {\"command\": \"bash -c \\\"...\\\"\", \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:2\", \"pid\": \"334423\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_fewnerd_mf4_v2_s456.log\", \"submitted_at\": \"2026-05-21T08:33:57.773Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/fewnerd/\", \"data_count\": 32565, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 456, \"checkpoint_path\": \"LOST - server shutdown\", \"kill_reason\": \"5090-b server shutdown by user\", \"wall_clock_seconds\": 5769.4, \"gpu_hours\": 1.6}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-21T10:10:07.222Z\"}, \"exp_conll_mf4_v2_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:34:10.294Z\", \"updated_at\": \"2026-05-21T09:11:29.209Z\", \"hypothesis\": \"MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). 3-seed set with exp_conll_t10_s42.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/conll_mf4v2_seed456/\\\"\", \"server\": \"autodl-5090-b\", \"gpu\": [\"cuda:1\"], \"pid\": \"334155\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_mf4_v2_s456.log\", \"submitted_at\": \"2026-05-21T08:33:55.428Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set (3453 instances, N=8)\", \"wall_clock_seconds\": 2253.8, \"gpu_hours\": 0.63}, \"checkpoint_path\": \"output/conll_mf4v2_seed456/\", \"metrics\": {\"greedy_f1\": 0.907, \"oracle_f1\": 0.9426, \"oracle_headroom\": 0.0357, \"fleiss_kappa_mean\": 0.768, \"soft_jaccard_mean\": 0.892, \"rho_SJ_full\": 0.4803, \"rho_kappa_full\": 0.4638, \"rho_SJ_cond\": 0.4513, \"rho_kappa_cond\": 0.425, \"logprob_rho_full\": 0.3213, \"logprob_rho_cond\": 0.3723, \"logprob_auroc_full\": 0.7569, \"logprob_auroc_cond\": 0.8221, \"sample_f1_mean\": 0.8737, \"sample_f1_pct_zero\": 7.08, \"structural_beats_surface\": true, \"rho_advantage\": 0.0166, \"verdict\": \"PASS\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T09:11:29.209Z\"}, \"exp_conll_mf4_v2_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:34:09.147Z\", \"updated_at\": \"2026-05-21T09:11:26.284Z\", \"hypothesis\": \"MF4 pipeline fix v2: CoNLL N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). 3-seed set with exp_conll_t10_s42.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/conll_mf4v2_seed123/\\\"\", \"server\": \"autodl-5090-b\", \"gpu\": [\"cuda:0\"], \"pid\": \"334013\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_mf4_v2_s123.log\", \"submitted_at\": \"2026-05-21T08:33:53.084Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set (3453 instances, N=8)\", \"wall_clock_seconds\": 2253.2, \"gpu_hours\": 0.63}, \"checkpoint_path\": \"output/conll_mf4v2_seed123/\", \"metrics\": {\"greedy_f1\": 0.9083, \"oracle_f1\": 0.9527, \"oracle_headroom\": 0.0444, \"fleiss_kappa_mean\": 0.762, \"soft_jaccard_mean\": 0.886, \"rho_SJ_full\": 0.4628, \"rho_kappa_full\": 0.4457, \"rho_SJ_cond\": 0.414, \"rho_kappa_cond\": 0.3887, \"logprob_rho_full\": 0.3281, \"logprob_rho_cond\": 0.367, \"logprob_auroc_full\": 0.7621, \"logprob_auroc_cond\": 0.8198, \"sample_f1_mean\": 0.8744, \"sample_f1_pct_zero\": 7.05, \"structural_beats_surface\": true, \"rho_advantage\": 0.0171, \"verdict\": \"PASS\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T09:11:26.284Z\"}, \"exp_frontier_sc_deepseek\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T06:50:26.022Z\", \"updated_at\": \"2026-05-21T09:10:40.589Z\", \"hypothesis\": \"Frontier model DeepSeek Chat on FewNERD SC (200 inst, N=8, T=1.0): 4-family cross-validation of correlation-selection gap universality.\", \"spec\": {\"command\": \"python -u code/run_frontier_sc.py --model deepseek/deepseek-chat --base_url http://47.94.22.126/v1 --dataset fewnerd --n_instances 200 --n_samples 8 --temperature 1.0 --output_dir output/frontier_sc_deepseek/ --max_workers 4\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 200, \"model_name\": \"deepseek/deepseek-chat\", \"seed\": 42}, \"checkpoint_path\": \"output/frontier_sc_deepseek/\", \"log_path\": \"logs/frontier_sc_deepseek.log\", \"metrics\": {\"greedy_f1\": 0.3992, \"mv_f1\": 0.4243, \"oracle_f1\": 0.714, \"degeneracy_rate\": 0.055, \"agreement_rho\": 0.2051, \"fleiss_kappa_rho\": 0.1471, \"sj_rho\": 0.1635, \"mv_gain_over_greedy\": 0.0251, \"selection_gap\": 0.2897, \"parse_failure_count\": 751, \"total_api_calls\": 1600, \"elapsed_s\": 4043.7}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T09:10:40.589Z\"}, \"exp_conll_n16_s456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:05:07.022Z\", \"updated_at\": \"2026-05-21T09:10:12.516Z\", \"hypothesis\": \"CoNLL N=16 (seed=456, v2): retry after previous failure on 5090. Third seed for 3-seed statistical power on CoNLL-2003 N=16.\", \"parent\": \"exp_conll_n16_s456\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/conll_n16_seed456_v2/\\\"\", \"server\": \"autodl-5090-c\", \"gpu\": [\"cuda:2\"], \"pid\": \"293990\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s456_v2.log\", \"submitted_at\": \"2026-05-21T07:18:17.355Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set (3453 instances, N=16)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_seed456_v2/\", \"wall_clock_seconds\": 6703.7, \"gpu_hours\": 1.86}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.9076, \"oracle_f1\": 0.955, \"oracle_headroom\": 0.0474, \"fleiss_kappa_mean\": 0.8, \"soft_jaccard_mean\": 0.8965, \"rho_SJ_full\": 0.4791, \"rho_kappa_full\": 0.4697, \"rho_SJ_cond\": 0.4481, \"rho_kappa_cond\": 0.4268, \"logprob_rho_full\": 0.3137, \"logprob_rho_cond\": 0.373, \"logprob_auroc_full\": 0.7524, \"logprob_auroc_cond\": 0.8236, \"sample_f1_mean\": 0.8736, \"sample_f1_pct_zero\": 7.03, \"verdict\": \"PASS\"}, \"completed_at\": \"2026-05-21T09:10:01.095Z\", \"checkpoint_path\": \"output/conll_n16_seed456_v2/\"}, \"exp_conll_n16_s123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:05:03.921Z\", \"updated_at\": \"2026-05-21T09:10:11.273Z\", \"hypothesis\": \"CoNLL N=16 (seed=123, v2): retry after previous failure on 5090 (damaged checkpoint). Extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003.\", \"parent\": \"exp_conll_n16_s123\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/conll_n16_seed123_v2/\\\"\", \"server\": \"autodl-5090-c\", \"gpu\": [\"cuda:1\"], \"pid\": \"293577\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s123_v2.log\", \"submitted_at\": \"2026-05-21T07:18:14.095Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set (3453 instances, N=16)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/conll_n16_seed123_v2/\", \"wall_clock_seconds\": 6702.6, \"gpu_hours\": 1.86}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.9071, \"oracle_f1\": 0.9625, \"oracle_headroom\": 0.0554, \"fleiss_kappa_mean\": 0.767, \"soft_jaccard_mean\": 0.877, \"rho_SJ_full\": 0.4567, \"rho_kappa_full\": 0.4469, \"rho_SJ_cond\": 0.4174, \"rho_kappa_cond\": 0.3936, \"logprob_rho_full\": 0.3456, \"logprob_rho_cond\": 0.375, \"logprob_auroc_full\": 0.7742, \"logprob_auroc_cond\": 0.8258, \"sample_f1_mean\": 0.8676, \"sample_f1_pct_zero\": 7.52, \"verdict\": \"PASS\"}, \"completed_at\": \"2026-05-21T09:09:56.663Z\", \"checkpoint_path\": \"output/conll_n16_seed123_v2/\"}, \"exp_frontier_sc_claude_sonnet4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T06:20:27.878Z\", \"updated_at\": \"2026-05-21T08:58:17.224Z\", \"hypothesis\": \"Frontier model Claude Sonnet 4 on FewNERD SC (200 instances, N=8, T=1.0): if correlation-selection gap persists across model families (GPT + Claude + Gemini + DeepSeek), the finding is universal and not model-specific.\", \"spec\": {\"command\": \"python -u code/run_frontier_sc.py --model anthropic/claude-sonnet-4 --base_url http://47.94.22.126/v1 --dataset fewnerd --data_dir data/fewnerd/ --n_instances 200 --n_samples 8 --temperature 1.0 --output_dir output/frontier_sc_claude_sonnet4/ --max_tokens 4096\", \"server\": \"autodl-5090\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 200, \"model_name\": \"anthropic/claude-sonnet-4\", \"seed\": 42, \"pid\": 6302, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/frontier_sc_claude_sonnet4.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/frontier_sc_claude_sonnet4/\", \"checkpoint_source\": \"API (http://47.94.22.126/v1)\", \"eval_data\": \"fewnerd test set (200 instances, N=8, T=1.0)\", \"matching\": \"text+type (case-insensitive, no offset)\", \"note\": \"v2: fixed from offset-based to text-based entity matching for API models\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.6068, \"mv_f1\": 0.6226, \"oracle_f1\": 0.6544, \"degeneracy_rate\": 0.74, \"selection_gap\": 0.0318, \"parse_failures\": 103, \"api_calls\": 1600, \"wall_clock_seconds\": 6118, \"instances\": 200}, \"completed_at\": \"2026-05-21T08:58:17.224Z\"}, \"exp_frontier_sc_gpt55_fewnerd_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:48:24.698Z\", \"updated_at\": \"2026-05-21T08:36:36.829Z\", \"hypothesis\": \"Frontier model GPT-5.5 on FewNERD SC (200 instances, N=8, T=1.0): if correlation-selection gap persists in frontier models, the finding is fundamental and not a model capability limitation. Previous attempt failed due to API credit exhaustion.\", \"parent\": \"exp_b_frontier_sc_fewnerd\", \"spec\": {\"command\": \"python -u code/run_frontier_sc.py --model gpt-5.5 --base_url http://47.94.22.126/v1 --n_instances 200 --n_samples 8 --temperature 1.0 --seed 42 --max_workers 4\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 200, \"model_name\": \"gpt-5.5\", \"seed\": 42, \"checkpoint_source\": \"openai/gpt-5.5 (API)\", \"eval_data\": \"fewnerd test set (200 instances)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/frontier_sc_gpt55_fewnerd_v2/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/frontier_sc_gpt55_fewnerd_v2.log\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.6382, \"mv_f1\": 0.6521, \"oracle_f1\": 0.7203, \"degeneracy_rate\": 0.5, \"rho_agreement\": 0.3551, \"rho_fk\": 0.3515, \"rho_sj\": 0.3461, \"instances\": 200}, \"completed_at\": \"2026-05-21T08:36:36.829Z\"}, \"exp_fewnerd_n16_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:46.569Z\", \"updated_at\": \"2026-05-21T08:33:07.868Z\", \"hypothesis\": \"FewNERD N=16 (seed=42): extending N-scaling curve to N=16 for Qwen3-8B-FT. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_n16_seed42/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_n16_seed42.log\"}, \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:2\", \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.7886, \"oracle_f1\": 0.9059, \"oracle_headroom\": 0.117, \"rho_fk_full\": 0.162, \"rho_sj_full\": 0.211, \"rho_fk_cond\": -0.019, \"rho_sj_cond\": 0.212, \"logprob_rho_full\": 0.139, \"logprob_rho_cond\": 0.175, \"instances\": 37648}, \"completed_at\": \"2026-05-21T08:33:07.868Z\"}, \"exp_fewnerd_t12_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:11:46.378Z\", \"updated_at\": \"2026-05-21T08:32:53.474Z\", \"hypothesis\": \"FewNERD temperature ablation (T=1.2, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.2 --seed 456 --collect_logprobs --output_dir output/fewnerd_t12_s456/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 456, \"gpu\": \"cuda:1\", \"pid\": 305834, \"tmux_session\": \"fewnerd_t12_s456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t12_s456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t12_s456/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.7885, \"oracle_f1\": 0.8775, \"oracle_headroom\": 0.089, \"rho_fk_full\": 0.191, \"rho_sj_full\": 0.29, \"rho_fk_cond\": 0.015, \"rho_sj_cond\": 0.254, \"degeneracy_rate\": null, \"logprob_rho_full\": 0.196, \"logprob_rho_cond\": 0.245, \"instances\": 37648}, \"completed_at\": \"2026-05-21T08:32:53.474Z\"}, \"exp_14b_inference_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-20T14:36:27.954Z\", \"updated_at\": \"2026-05-21T07:51:33.030Z\", \"hypothesis\": \"14B Qwen2.5 inference on FewNERD (N∈{1,2,4,8}): primary dataset should show oracle scaling law F1(N)=a-b*N^(-c) consistent at 14B scale, filling the scaling curve between 7B and 32B. N=16 cut per Director decision.\", \"notes\": \"2026-05-21T00:50 RESTORED to RUNNING per Director. PID 252310 confirmed alive by Reviewer (cuda:0 98% util, elapsed 16min). 5th false-negative misdiagnosis. N=1 greedy_f1=0.7985, N=2 greedy_f1=0.7985/oracle=0.8086, N=4 greedy_f1=0.7984/oracle=0.8544. kill_after_n8.sh active (PID 224789).\", \"spec\": {\"server\": \"autodl-5090-c\", \"pid\": 252310, \"gpu\": \"cuda:0\", \"model_name\": \"Qwen2.5-14B-Instruct\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:0\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T00:46:56.565632+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T07:17:12.232308+00:00\"}]}, \"conclusion\": \"success\", \"reproduce\": {\"finished_at\": \"2026-05-21T07:17:01.438Z\"}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-21T07:17:05.380Z\", \"metrics\": {\"fewnerd_n1\": {\"greedy_f1\": 0.7985, \"oracle_f1\": 0.7541, \"oracle_headroom\": -0.044, \"verdict\": \"FAIL\"}, \"fewnerd_n2\": {\"greedy_f1\": 0.7985, \"oracle_f1\": 0.8086, \"oracle_headroom\": 0.01, \"soft_jaccard_rho_full\": 0.205, \"rho_advantage\": -0.006, \"structural_beats_surface\": false, \"verdict\": \"FAIL\"}, \"fewnerd_n4\": {\"greedy_f1\": 0.7984, \"oracle_f1\": 0.8544, \"oracle_headroom\": 0.056, \"soft_jaccard_rho_full\": 0.314, \"rho_advantage\": 0.042, \"structural_beats_surface\": true, \"verdict\": \"MARGINAL\"}, \"fewnerd_n8\": {\"greedy_f1\": 0.7984, \"oracle_f1\": 0.8791, \"oracle_headroom\": 0.081, \"soft_jaccard_rho_full\": 0.324, \"rho_advantage\": 0.083, \"structural_beats_surface\": true, \"verdict\": \"MARGINAL\"}, \"cross_domain_scierc_conll\": \"completed but expected poor (cross-domain)\", \"n16_status\": \"cut per Director decision, kill_after_n8.sh executed\"}, \"checkpoint_path\": \"output/14b_final_inference/\"}, \"exp_fewnerd_mf4_v2_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:33:24.304Z\", \"updated_at\": \"2026-05-21T07:44:50.506Z\", \"hypothesis\": \"MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=42 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1. 3-seed statistical power.\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/fewnerd_mf4v2_seed42/\", \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0\", \"pid\": 320158, \"log_path\": \"~/runs/struct_self_consist_ie/exp_fewnerd_mf4_v2_s42.log\", \"submitted_at\": \"2026-05-21T05:33:33.770Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 42, \"checkpoint_path\": \"output/fewnerd_mf4v2_seed42/\", \"wall_clock_seconds\": 7644}, \"reproduce\": {\"finished_at\": \"2026-05-21T07:40:57.810Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-21T07:41:07.901551+00:00\"}]}, \"metrics\": {\"greedy_f1\": 0.7883, \"oracle_f1\": 0.8783, \"oracle_headroom\": 0.09, \"fleiss_kappa_mean\": 0.3531, \"soft_jaccard_mean\": 0.6747, \"rho_SJ_full\": 0.1634, \"rho_kappa_full\": 0.0476, \"rho_SJ_cond\": 0.1987, \"rho_kappa_cond\": -0.0327, \"rho_advantage_full\": 0.1158, \"rho_advantage_cond\": 0.2314, \"structural_beats_surface\": true, \"sample_f1_mean\": 0.6123, \"sample_f1_std\": 0.3913, \"sample_f1_pct_zero\": 23.09, \"n_instances\": 37648, \"n_valid_full\": 32565, \"n_valid_cond\": 28682, \"n_gold_empty_filtered\": 5083, \"n_greedy_f1_zero_filtered\": 3883, \"logprob_rho_full\": 0.1544, \"logprob_tau_full\": 0.115, \"logprob_auroc_full\": 0.5771, \"logprob_rho_cond\": 0.1641, \"logprob_tau_cond\": 0.123, \"logprob_auroc_cond\": 0.5768, \"verdict\": \"FAIL\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-21T07:44:50.506Z\"}, \"exp_fewnerd_mf4_v2_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:33:25.463Z\", \"updated_at\": \"2026-05-21T07:41:29.072Z\", \"hypothesis\": \"MF4 pipeline fix v2: FewNERD N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). Replaces exp_021 which used incompatible greedy_macro_f1. 3-seed statistical power.\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/fewnerd_mf4v2_seed123/\", \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:1\", \"pid\": 320302, \"log_path\": \"~/runs/struct_self_consist_ie/exp_fewnerd_mf4_v2_s123.log\", \"submitted_at\": \"2026-05-21T05:33:36.193Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 123, \"checkpoint_path\": \"output/fewnerd_mf4v2_seed123/\", \"wall_clock_seconds\": 7672.9, \"gpu_hours\": 2.13}, \"reproduce\": {\"finished_at\": \"2026-05-21T07:38:22.503Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-21T07:38:30.204681+00:00\"}]}, \"metrics\": {\"greedy_f1\": 0.7883, \"oracle_f1\": 0.8891, \"oracle_headroom\": 0.1009, \"fleiss_kappa_mean\": 0.3483, \"soft_jaccard_mean\": 0.6689, \"rho_SJ_full\": 0.307, \"rho_kappa_full\": 0.1588, \"rho_SJ_cond\": 0.1966, \"rho_kappa_cond\": 0.0031, \"rho_advantage_full\": 0.1482, \"rho_advantage_cond\": 0.1935, \"structural_beats_surface\": true, \"sample_f1_mean\": 0.6364, \"sample_f1_std\": 0.3819, \"sample_f1_pct_zero\": 20.49, \"n_instances\": 37648, \"n_valid_full\": 32565, \"n_valid_cond\": 28685, \"n_gold_empty_filtered\": 5083, \"n_greedy_f1_zero_filtered\": 3880, \"logprob_rho_full\": 0.2193, \"logprob_tau_full\": 0.1641, \"logprob_auroc_full\": 0.6056, \"logprob_rho_cond\": 0.1818, \"logprob_tau_cond\": 0.1369, \"logprob_auroc_cond\": 0.5892, \"verdict\": \"MARGINAL\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T07:41:29.072Z\"}, \"exp_fewnerd_7b_n16_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:32:29.897Z\", \"updated_at\": \"2026-05-21T07:17:35.321Z\", \"hypothesis\": \"FewNERD N=16 with Qwen2.5-7B: extending N-scaling curve to N=16 for 7B model. At N=8 the 7B model shows diminishing oracle gains; N=16 tests whether the plateau continues or breaks, providing a critical data point for the N-scaling law F1(N)=a-b*N^(-c) at the 7B scale.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen25-7b-fewnerd-merged --data_dir data/fewnerd/ --dataset fewnerd --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/fewnerd_7b_n16_seed42/\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen25-7b-fewnerd-merged\", \"seed\": 42, \"gpu\": \"cuda:2\", \"pid\": 264869, \"log_path\": \"N/A\", \"checkpoint_path\": \"N/A\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-fewnerd-merged\", \"eval_data\": \"fewnerd test set (37648 instances, N=16)\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T07:17:35.321Z\"}, \"exp_fewnerd_n16_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:45.512Z\", \"updated_at\": \"2026-05-21T07:13:32.225Z\", \"hypothesis\": \"FewNERD N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation. Third seed for 3-seed statistical power.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/fewnerd_n16_seed456/\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/fewnerd/\", \"data_count\": 14770, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 456}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T07:13:32.225Z\"}, \"exp_conll_mf4_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:09:11.484Z\", \"updated_at\": \"2026-05-21T06:54:56.063Z\", \"hypothesis\": \"MF4 pipeline fix: CoNLL N=8 T=1.0 seed=456 using run_mvp_pilot.py (greedy_f1/micro-F1). Extends exp_conll_t10_s42 to 3-seed set for statistical power.\", \"parent\": \"exp_conll_t10_s42\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/conll_mf4_seed456/\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"data/conll2003/test.json\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-21T06:54:56.063Z\"}, \"exp_conll_mf4_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T05:09:06.021Z\", \"updated_at\": \"2026-05-21T05:53:05.635Z\", \"hypothesis\": \"MF4 pipeline fix: CoNLL N=8 T=1.0 seed=123 using run_mvp_pilot.py (greedy_f1/micro-F1). Extends exp_conll_t10_s42 to 3-seed set for statistical power.\", \"parent\": \"exp_conll_t10_s42\", \"spec\": {\"command\": \"python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/conll_mf4_seed123/\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003/\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"data/conll2003/test.json\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-21T05:53:05.635Z\"}, \"exp_fewnerd_t05_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:11:43.659Z\", \"updated_at\": \"2026-05-21T05:50:43.777Z\", \"hypothesis\": \"FewNERD temperature ablation (T=0.5, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.5 --seed 456 --collect_logprobs --output_dir output/fewnerd_t05_s456/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 456, \"gpu\": \"cuda:0\", \"pid\": 305832, \"tmux_session\": \"fewnerd_t05_s456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t05_s456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t05_s456/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"reproduce\": {\"finished_at\": \"2026-05-21T05:32:07.140Z\"}, \"failure_reason\": \"false alarm: cron detected process dead but experiment had completed successfully (37648/37648 instances, report.json + samples.jsonl generated)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T05:32:10.869Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T05:32:18.820026+00:00\"}]}}, \"exp_14b_inference_conll\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T14:36:26.315Z\", \"updated_at\": \"2026-05-21T04:57:40.651Z\", \"hypothesis\": \"14B Qwen2.5 inference on CoNLL (N∈{1,2,4,8}): filling scale curve between 8B (greedy F1=0.907) and 32B. Tests whether 14B shows intermediate behavior in SC diagnostic metrics.\", \"reproduce\": {\"finished_at\": \"2026-05-20T14:49:00.238Z\"}, \"failure_reason\": \"Director ordered kill: cross-domain 14B inference deemed valueless by Reviewer. Only FewNERD 14B inference retained.\", \"conclusion\": \"killed\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T14:49:09.529266+00:00\"}]}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"spec\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"pid\": 278145, \"model_name\": \"Qwen2.5-14B-Instruct (base)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003/\", \"data_count\": 3453, \"seed\": 42, \"command\": \"python -u code/run_mvp_pilot.py --model_path Qwen/Qwen2.5-14B-Instruct --data_dir data/conll2003/ --dataset conll2003 --n_samples 8 --temperature 1.0 --seed 42 --enforce_eager --output_dir output/14b_base_inference/conll2003_n1/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/14b_conll_inference.log\"}, \"completed_at\": \"2026-05-21T04:57:40.651Z\"}, \"exp_conll_n16_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:49.693Z\", \"updated_at\": \"2026-05-21T04:53:40.278Z\", \"hypothesis\": \"CoNLL N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation. Third seed for 3-seed statistical power.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie/ && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/conll_n16_s456/\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"996070\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s456.log\", \"submitted_at\": \"2026-05-21T04:51:06.525Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 40.2, \"gpu_hours\": 0.01}, \"pid\": \"996070\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s456.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie/ && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/conll_n16_s456/\\\"\", \"finished_at\": \"2026-05-21T04:51:43.069Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T04:51:46.724Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T04:51:52.994852+00:00\"}]}, \"notes\": \"失败原因: tokenizer vocab_file=None — checkpoints/qwen3-8b-conll2003-merged 缺少 vocab.json，vLLM 初始化 tokenizer 时 TypeError。与 exp_conll_n16_s123 同根因。| 已有成果: 无（启动即崩溃）| 建议: 修复 merged checkpoint tokenizer 文件后重跑\"}, \"exp_conll_n16_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:48.660Z\", \"updated_at\": \"2026-05-21T04:53:39.049Z\", \"hypothesis\": \"CoNLL N=16 (seed=123): extending N-scaling curve to N=16 for Qwen3-8B-FT on CoNLL-2003. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation. Second seed (s42 running).\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie/ && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/conll_n16_s123/\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"995788\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s123.log\", \"submitted_at\": \"2026-05-21T04:50:56.582Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 36.3, \"gpu_hours\": 0.01}, \"pid\": \"995788\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_conll_n16_s123.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie/ && python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --output_dir output/conll_n16_s123/\\\"\", \"finished_at\": \"2026-05-21T04:51:29.216Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T04:51:32.929Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T04:51:39.166251+00:00\"}]}, \"notes\": \"失败原因: tokenizer vocab_file=None — checkpoints/qwen3-8b-conll2003-merged 缺少 vocab.json，vLLM 初始化 tokenizer 时 TypeError。与 exp_conll_n16_s456 同根因。| 已有成果: 无（启动即崩溃）| 建议: 修复 merged checkpoint tokenizer 文件后重跑\"}, \"exp_scierc_n16_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:30:43.414Z\", \"updated_at\": \"2026-05-21T04:44:33.829Z\", \"hypothesis\": \"SciERC N=16 (seed=456): extending N-scaling curve to N=16 for Qwen3-8B-FT on SciERC. Tests whether oracle gains plateau or continue at higher sample counts, critical for F1(N)=a-b*N^(-c) scaling law estimation. Third seed for 3-seed statistical power.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --output_dir output/scierc_n16_seed456/\", \"server\": \"autodl-5090-b\", \"data_path\": \"data/scierc/processed_data/\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456}, \"log_path\": \"logs/scierc_n16_seed456.log\", \"checkpoint_path\": \"output/scierc_n16_seed456/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:44:33.829Z\"}, \"exp_scierc_t12_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:24:04.240Z\", \"updated_at\": \"2026-05-21T04:25:04.160Z\", \"hypothesis\": \"SciERC temperature ablation (T=1.2, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.\", \"parent\": \"exp_scierc_t12_s123\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t12_s456/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t12_s456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:22.602Z\", \"metrics\": {\"greedy_f1\": 0.663, \"oracle_f1\": 0.782, \"rho_SJ_full\": 0.42, \"rho_FK_full\": 0.32, \"rho_advantage\": 0.099, \"oracle_headroom\": 0.119, \"degeneracy_pct\": 14.1, \"verdict\": \"PASS\"}}, \"exp_scierc_t08_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:11:56.854Z\", \"updated_at\": \"2026-05-21T04:25:01.025Z\", \"hypothesis\": \"SciERC temperature ablation (T=0.8, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 8 --temperature 0.8 --seed 123 --collect_logprobs --output_dir output/scierc_t08_s123/\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data/test.json\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": \"cuda:1\", \"pid\": 269240, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t08_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t08_s123/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"scierc test set (551 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:17.181Z\", \"metrics\": {\"greedy_f1\": 0.662, \"oracle_f1\": 0.773, \"rho_SJ_full\": 0.382, \"rho_FK_full\": 0.298, \"rho_advantage\": 0.084, \"oracle_headroom\": 0.11, \"degeneracy_pct\": 11.2, \"verdict\": \"MARGINAL\"}}, \"exp_scierc_t08_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:24:03.202Z\", \"updated_at\": \"2026-05-21T04:24:59.796Z\", \"hypothesis\": \"SciERC temperature ablation (T=0.8, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.\", \"parent\": \"exp_scierc_t08_s123\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t08_s456/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t08_s456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:14.128Z\", \"metrics\": {\"greedy_f1\": 0.664, \"oracle_f1\": 0.769, \"rho_SJ_full\": 0.362, \"rho_FK_full\": 0.244, \"rho_advantage\": 0.118, \"oracle_headroom\": 0.105, \"degeneracy_pct\": 11.9, \"verdict\": \"MARGINAL\"}}, \"exp_scierc_t05_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:24:01.834Z\", \"updated_at\": \"2026-05-21T04:24:58.182Z\", \"hypothesis\": \"SciERC temperature ablation (T=0.5, seed=456): third seed for SciERC T-ablation 3-seed statistical power. N=8, Qwen3-8B-FT.\", \"parent\": \"exp_scierc_t05_s123\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t05_s456/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t05_s456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:11.475Z\", \"metrics\": {\"greedy_f1\": 0.663, \"oracle_f1\": 0.746, \"rho_SJ_full\": 0.326, \"rho_FK_full\": 0.272, \"rho_advantage\": 0.054, \"oracle_headroom\": 0.083, \"degeneracy_pct\": 10.3, \"verdict\": \"MARGINAL\"}}, \"exp_scierc_t12_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:11:53.869Z\", \"updated_at\": \"2026-05-21T04:24:56.285Z\", \"hypothesis\": \"SciERC temperature ablation (T=1.2, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 8 --temperature 1.2 --seed 123 --collect_logprobs --output_dir output/scierc_t12_s123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data/test.json\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": \"cuda:3\", \"pid\": 305838, \"tmux_session\": \"scierc_t12_s123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t12_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t12_s123/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"scierc test set (551 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:08.764Z\", \"metrics\": {\"greedy_f1\": 0.664, \"oracle_f1\": 0.788, \"rho_SJ_full\": 0.346, \"rho_FK_full\": 0.223, \"rho_advantage\": 0.124, \"oracle_headroom\": 0.124, \"degeneracy_pct\": 13.9, \"verdict\": \"MARGINAL\"}}, \"exp_scierc_t05_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:11:49.272Z\", \"updated_at\": \"2026-05-21T04:24:54.884Z\", \"hypothesis\": \"SciERC temperature ablation (T=0.5, seed=123): second seed for SciERC T-ablation replication. N=8, Qwen3-8B-FT.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data/ --dataset scierc --subtask ner --n_samples 8 --temperature 0.5 --seed 123 --collect_logprobs --output_dir output/scierc_t05_s123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data/test.json\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": \"cuda:2\", \"pid\": 305836, \"tmux_session\": \"scierc_t05_s123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_t05_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/scierc_t05_s123/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"scierc test set (551 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:06.127Z\", \"metrics\": {\"greedy_f1\": 0.665, \"oracle_f1\": 0.743, \"rho_SJ_full\": 0.322, \"rho_FK_full\": 0.295, \"rho_advantage\": 0.026, \"oracle_headroom\": 0.078, \"degeneracy_pct\": 10, \"verdict\": \"MARGINAL\"}}, \"exp_fewnerd_t08_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:47:48.690Z\", \"updated_at\": \"2026-05-21T04:24:53.510Z\", \"hypothesis\": \"FewNERD T-ablation seed=456 (T=0.8): third seed for T=0.8 sweet-spot, providing 3-seed statistical power for the key operating point. With seeds 42/123/456, can compute confidence intervals on rho_SJ and degeneracy_rate for the recommended T=0.8 setting.\", \"parent\": \"exp_fewnerd_t08_s42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.8 --seed 456 --collect_logprobs --output_dir output/fewnerd_t08_s456/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 456, \"gpu\": \"cuda:3\", \"tmux_session\": \"fewnerd_t08_s456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t08_s456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t08_s456/\", \"pid\": 297409, \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:24:03.444Z\", \"metrics\": {\"greedy_f1\": 0.788, \"oracle_f1\": 0.877, \"rho_SJ_full\": 0.328, \"rho_FK_full\": 0.202, \"rho_advantage\": 0.126, \"oracle_headroom\": 0.088, \"degeneracy_pct\": 16.3, \"verdict\": \"MARGINAL\"}}, \"exp_fewnerd_t12_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:47:46.558Z\", \"updated_at\": \"2026-05-21T04:24:52.149Z\", \"hypothesis\": \"FewNERD T-ablation seed=123 replication (T=1.2): second seed for statistical power on T=1.2 negative result (over-diversification, 28.2% degeneracy, lowest rho_SJ=0.136 in seed=42). Confirms T=1.2 is consistently suboptimal for SC diagnostics on FewNERD.\", \"parent\": \"exp_fewnerd_t12_s42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.2 --seed 123 --collect_logprobs --output_dir output/fewnerd_t12_s123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 123, \"gpu\": \"cuda:2\", \"tmux_session\": \"fewnerd_t12_s123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t12_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t12_s123/\", \"pid\": 297143, \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-21T04:24:00.722Z\", \"metrics\": {\"greedy_f1\": 0.789, \"oracle_f1\": 0.887, \"rho_SJ_full\": 0.285, \"rho_FK_full\": 0.163, \"rho_advantage\": 0.122, \"oracle_headroom\": 0.098, \"degeneracy_pct\": 24.7, \"verdict\": \"FAIL\"}}, \"exp_fewnerd_t08_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:47:44.136Z\", \"updated_at\": \"2026-05-21T04:24:50.244Z\", \"hypothesis\": \"FewNERD T-ablation seed=123 replication (T=0.8): second seed for statistical power on T=0.8 sweet-spot hypothesis (best rho_advantage=0.102 SJ over Fleiss, balanced oracle headroom=8.66% in seed=42). Tests robustness of T=0.8 as optimal operating point for SC diagnostic.\", \"parent\": \"exp_fewnerd_t08_s42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.8 --seed 123 --collect_logprobs --output_dir output/fewnerd_t08_s123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 123, \"gpu\": \"cuda:1\", \"tmux_session\": \"fewnerd_t08_s123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t08_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t08_s123/\", \"pid\": 296880, \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:23:57.853Z\", \"metrics\": {\"greedy_f1\": 0.789, \"oracle_f1\": 0.884, \"rho_SJ_full\": 0.336, \"rho_FK_full\": 0.221, \"rho_advantage\": 0.116, \"oracle_headroom\": 0.095, \"degeneracy_pct\": 16.7, \"verdict\": \"MARGINAL\"}}, \"exp_fewnerd_t05_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:47:41.794Z\", \"updated_at\": \"2026-05-21T04:24:48.794Z\", \"hypothesis\": \"FewNERD T-ablation seed=123 replication (T=0.5): second seed for statistical power on T=0.5 findings (highest rho_SJ=0.267, lowest oracle headroom=6.85% in seed=42). Confirms whether the diagnostic correlation ranking T=0.5>T=0.8>T=1.2 is stable across seeds or driven by seed-specific variance.\", \"parent\": \"exp_fewnerd_t05_s42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.5 --seed 123 --collect_logprobs --output_dir output/fewnerd_t05_s123/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 123, \"gpu\": \"cuda:0\", \"tmux_session\": \"fewnerd_t05_s123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t05_s123.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t05_s123/\", \"pid\": 296744, \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-exp021-merged\", \"eval_data\": \"fewnerd test set (37648 instances)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:23:54.964Z\", \"metrics\": {\"greedy_f1\": 0.789, \"oracle_f1\": 0.864, \"rho_SJ_full\": 0.35, \"rho_FK_full\": 0.295, \"rho_advantage\": 0.055, \"oracle_headroom\": 0.075, \"degeneracy_pct\": 13.5, \"verdict\": \"MARGINAL\"}}, \"exp_32b_inference_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:21:12.060Z\", \"updated_at\": \"2026-05-21T04:24:47.338Z\", \"hypothesis\": \"32B fine-tuned model (Qwen2.5-32B-Instruct QLoRA, best checkpoint-32000) FewNERD inference with N=8 SC sampling. Scaling from 8B→32B should improve per-sample quality and strengthen SC diagnostic correlation (Fleiss kappa / Soft-Jaccard vs F1). Comparison baseline: Qwen3-8B-FT FewNERD results.\", \"parent\": \"exp_qwen25_32b_fewnerd\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_32b_fewnerd_n8_s42/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/inference_32b_fewnerd_n8_s42.log\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen25-32b-fewnerd-merged --data_dir data/fewnerd --dataset fewnerd --n_samples 8 --temperature 1.0 --seed 42 --output_dir output/exp_32b_fewnerd_n8_s42 --tensor_parallel 4 --collect_logprobs\", \"server\": \"autodl-5090\", \"model_name\": \"qwen25-32b-fewnerd-merged\", \"seed\": 42, \"data_path\": \"data/fewnerd\", \"data_count\": 301184}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:23:52.252Z\", \"metrics\": {\"greedy_f1\": 0.8, \"oracle_f1\": 0.879, \"rho_SJ_full\": 0.32, \"rho_FK_full\": 0.242, \"rho_advantage\": 0.078, \"fleiss_kappa_mean\": 0.533, \"soft_jaccard_mean\": 0.802, \"oracle_headroom\": 0.079, \"verdict\": \"MARGINAL\"}}, \"exp_hidden_state_probe_fulldata\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:13:17.554Z\", \"updated_at\": \"2026-05-21T04:13:53.843Z\", \"hypothesis\": \"Hidden states of fine-tuned Qwen3-8B encode entity quality information that a linear probe can detect with AUROC significantly above chance, even under GroupKFold (no instance leakage). CoNLL probe should exceed MV baseline (0.87).\", \"spec\": {\"command\": \"extract_fulldata_hidden_states.py + groupkfold_probe_fulldata.py\", \"server\": \"autodl-5090-b (fewnerd), autodl-5090-c (conll, scierc)\", \"data_path\": \"output/entity_probe_fulldata/\", \"data_count\": \"CoNLL 850inst/14777ent, FewNERD 1698inst/41096ent, SciERC 539inst/13188ent\", \"model_name\": \"Qwen3-8B fine-tuned\", \"seed\": \"42,123,456\"}, \"log_path\": \"artifacts/exp_hidden_state_probe_fulldata/data/groupkfold_probe_fulldata_results.json\", \"checkpoint_path\": \"output/entity_probe_fulldata/ on autodl-5090-b and autodl-5090-c\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T04:13:53.843Z\"}, \"exp_hidden_state_probe\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:07:00.977Z\", \"updated_at\": \"2026-05-21T03:21:54.284Z\", \"hypothesis\": \"Entity quality information (in_gold vs not) is encoded in the fine-tuned model's last-layer hidden states at entity token positions. If probe AUROC ≈ MV AUROC (0.87), the signal exists in representation but ESJ prompt-based reading (AUROC=0.51) fails to access it — a prompt interface failure. If probe AUROC ≈ 0.51, the information is genuinely absent from single-sample representations.\", \"spec\": {\"command\": \"python code/hidden_state_probe.py --dataset {fewnerd,conll} --max_instances 500\", \"server\": \"autodl-5090-c\", \"data_path\": \"output/{exp_tlow_fewnerd_t05_s42,exp_conll_t08_seed42}/samples.jsonl\", \"data_count\": 1000, \"model_name\": \"Qwen3-8B-FT (per-dataset checkpoints)\", \"seed\": 42, \"gpu\": \"cuda:2 (fewnerd), cuda:3 (conll)\", \"pid\": 261583, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/probe_extract_{fewnerd,conll}.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/entity_probe_auroc/\"}, \"metrics\": {\"entity_level_stratifiedkfold_auroc\": {\"conll\": 0.9796, \"fewnerd\": 0.9872, \"scierc\": 0.9766}, \"groupkfold_auroc_corrected\": {\"conll\": 0.8849, \"fewnerd\": 0.6513, \"scierc\": 0.6344}, \"groupkfold_delta\": {\"conll\": -0.0947, \"fewnerd\": -0.3359, \"scierc\": -0.3422}, \"groupkfold_probe_above_mv\": {\"conll\": true, \"fewnerd\": false, \"scierc\": false}, \"baselines\": {\"mv_agreement_auroc\": 0.87, \"esj_prompt_auroc\": 0.51}, \"note\": \"GroupKFold fixes instance-level leakage. Only conll retains probe > MV after correction.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T02:11:40.936Z\", \"notes\": \"Probe AUROC far exceeds both baselines: FewNERD 0.987, CoNLL 0.980 vs MV 0.87 vs ESJ 0.51. The model's last-layer hidden states at entity token positions encode correctness information at very high fidelity — even higher than what multi-sample voting captures. This is strong evidence for a prompt interface failure: the model knows which entities are correct but cannot express this through prompting (ESJ). LogisticRegression with 5-fold CV × 3 seeds. SciERC extraction not run (no matching 8B samples data available).\"}, \"exp_conll_t10_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:32:32.990Z\", \"updated_at\": \"2026-05-21T02:44:20.817Z\", \"hypothesis\": \"CoNLL T=1.0 baseline (seed=42): fills the gap in the temperature ablation matrix (T=0.5/0.8/1.2 already complete with 3 seeds). T=1.0 is the default sampling temperature and should show intermediate behavior between T=0.8 (sweet spot) and T=1.2 (over-diversification), completing the temperature sweep for CoNLL.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --n_samples 8 --temperature 1.0 --seed 42 --collect_logprobs --output_dir output/exp_conll_t10_seed42/\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003/test.json\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42, \"gpu\": \"cuda:3\", \"pid\": 265554, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/conll_t10_seed42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t10_seed42/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set (3453 instances)\"}, \"metrics\": {\"greedy_f1\": 0.9077, \"oracle_f1\": 0.9503, \"oracle_headroom\": 0.0426, \"rho_SJ_full\": 0.4249, \"rho_kappa_full\": 0.4037, \"rho_SJ_cond\": 0.4154, \"rho_kappa_cond\": 0.3793, \"rho_advantage\": 0.0212, \"fleiss_kappa_mean\": 0.772, \"soft_jaccard_mean\": 0.895, \"sample_f1_mean\": 0.871, \"sample_f1_pct_zero\": 7.53, \"verdict\": \"PASS\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T02:44:20.817Z\"}, \"exp_scierc_probe\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:32:25.557Z\", \"updated_at\": \"2026-05-21T02:41:37.846Z\", \"hypothesis\": \"SciERC hidden state probe: test if linear classifier on last-layer hidden states can predict entity quality (match vs non-match against gold). If AUROC ≈ 0.98 (consistent with FewNERD=0.987, CoNLL=0.980), confirms entity quality info is universally encoded in representations across datasets, and prompt-based self-judgment (ESJ AUROC=0.51) fails to access this information.\", \"spec\": {\"command\": \"Step 1: CUDA_VISIBLE_DEVICES=1 python -u code/run_mvp_pilot.py --dataset scierc --n_samples 8 --temperature 0.8; Step 2: python code/hidden_state_probe.py --dataset scierc --gpu 1\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data/test.json\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"gpu\": \"cuda:1\", \"pid\": 264061, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scierc_8b_inference.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/entity_probe_auroc/\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"scierc test set (551 instances)\"}, \"metrics\": {\"scierc_auroc_mean\": 0.9766, \"scierc_auroc_std\": 0.0011, \"scierc_auroc_seeds\": [0.9771, 0.9751, 0.9775], \"n_entities\": 12933, \"positive_rate\": 0.654, \"interpretation\": \"HIGH — info in representation, prompt interface fails\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T02:41:37.846Z\"}, \"exp_multi_model_correlation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T02:04:21.487Z\", \"updated_at\": \"2026-05-21T02:05:04.778Z\", \"hypothesis\": \"Cross-family models (Qwen vs LLaMA) have lower per-instance error correlation than same-family models, explaining why cross-model ensemble improves F1 by +0.42pp\", \"spec\": {\"command\": \"python3 code/multi_model_error_correlation.py --output_dir output/multi_model_correlation/\", \"server\": \"autodl-5090\", \"data_path\": \"output/*/samples.jsonl\", \"data_count\": 9004, \"model_name\": \"Qwen3-8B-FT + LLaMA-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/multi_model_correlation/error_correlation_report.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T02:05:04.778Z\"}, \"exp_conll_t12_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:43:52.368Z\", \"updated_at\": \"2026-05-21T01:59:40.017Z\", \"hypothesis\": \"CoNLL temperature ablation (T=1.2, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"parent\": \"exp_conll_t12_s123\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 1.2 --seed 456 --output_dir output/exp_conll_t12_seed456\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"pid\": 255217, \"gpu\": \"cuda:3\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t12_seed456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t12_seed456/\", \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"data/conll2003\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.9071, \"oracle_f1\": 0.9452, \"oracle_headroom\": 0.0381, \"fleiss_kappa_mean\": 0.7005, \"soft_jaccard_mean\": 0.8513, \"rho_SJ_F1_full\": 0.4553, \"rho_SJ_F1_conditional\": 0.4259, \"degeneracy_rate_pct\": 8.34, \"rho_advantage\": 0.0265, \"verdict\": \"PASS\"}, \"completed_at\": \"2026-05-21T01:59:40.017Z\"}, \"exp_conll_t08_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:43:51.393Z\", \"updated_at\": \"2026-05-21T01:59:37.027Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.8, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"parent\": \"exp_conll_t08_s123\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 0.8 --seed 456 --output_dir output/exp_conll_t08_seed456\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"pid\": 254524, \"gpu\": \"cuda:2\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t08_seed456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t08_seed456/\", \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"data/conll2003\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.9064, \"oracle_f1\": 0.9407, \"oracle_headroom\": 0.0343, \"fleiss_kappa_mean\": 0.8229, \"soft_jaccard_mean\": 0.9233, \"rho_SJ_F1_full\": 0.4877, \"rho_SJ_F1_conditional\": 0.4756, \"degeneracy_rate_pct\": 6.29, \"rho_advantage\": 0.0058, \"verdict\": \"PASS\"}, \"completed_at\": \"2026-05-21T01:59:37.027Z\"}, \"exp_conll_t05_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:43:49.873Z\", \"updated_at\": \"2026-05-21T01:59:34.389Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.5, seed=456): third seed complementing seed=42+123 for 3-seed statistical power. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"parent\": \"exp_conll_t05_s123\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 0.5 --seed 456 --output_dir output/exp_conll_t05_seed456\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 456, \"pid\": 253823, \"gpu\": \"cuda:1\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t05_seed456.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t05_seed456/\", \"checkpoint_source\": \"checkpoints/qwen3-8b-conll2003-merged\", \"eval_data\": \"data/conll2003\"}, \"conclusion\": \"success\", \"metrics\": {\"greedy_f1\": 0.9075, \"oracle_f1\": 0.9338, \"oracle_headroom\": 0.0263, \"fleiss_kappa_mean\": 0.8885, \"soft_jaccard_mean\": 0.9551, \"rho_SJ_F1_full\": 0.4549, \"rho_SJ_F1_conditional\": 0.469, \"degeneracy_rate_pct\": 5.62, \"rho_advantage\": 0.0044, \"verdict\": \"PASS\"}, \"completed_at\": \"2026-05-21T01:59:34.389Z\"}, \"exp_fewnerd_t05_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:41:05.687Z\", \"updated_at\": \"2026-05-21T00:47:06.206Z\", \"hypothesis\": \"FewNERD temperature ablation (T=0.5): test how lower temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwen3-8B-FT, seed=42. Lower T should reduce sampling diversity, potentially increasing degeneracy while improving per-sample quality.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.5 --seed 42 --collect_logprobs --output_dir output/fewnerd_t05_s42/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 42, \"gpu\": \"cuda:0\", \"tmux_session\": \"fewnerd_t05\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t05_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t05_s42/\"}, \"metrics\": {\"greedy_f1\": 0.7884, \"oracle_f1\": 0.8569, \"oracle_headroom\": 0.0685, \"sample_f1_mean\": 0.7154, \"degeneracy_rate\": 0.146, \"fleiss_kappa_mean\": 0.6332, \"soft_jaccard_mean\": 0.8653, \"rho_SJ_F1_full\": 0.2667, \"rho_SJ_F1_conditional\": 0.2988, \"rho_fleiss_F1_full\": 0.2231, \"rho_fleiss_F1_conditional\": 0.2338, \"rho_logprob_F1_full\": 0.3558, \"rho_logprob_F1_conditional\": 0.3025, \"structural_beats_surface\": true, \"rho_advantage\": 0.0435}, \"conclusion\": \"success\", \"notes\": \"T=0.5 on FewNERD has highest absolute rho_SJ=0.267 (full), 0.299 (conditional) among T-ablation, but lowest oracle headroom (6.85%) meaning SC oracle gain is smallest. Lowest degeneracy (14.6%), highest sample quality (0.715). SJ advantage over Fleiss only 0.044 because Fleiss also high (0.223). Logprob baseline dominates at this T (rho=0.356). Tradeoff: low T maximizes diagnostic correlation but minimizes room for SC to help.\", \"completed_at\": \"2026-05-21T00:47:06.206Z\"}, \"exp_fewnerd_t08_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:41:07.634Z\", \"updated_at\": \"2026-05-21T00:45:13.333Z\", \"hypothesis\": \"FewNERD temperature ablation (T=0.8): test how moderate-low temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwen3-8B-FT, seed=42. T=0.8 is a sweet-spot candidate balancing diversity and quality.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.8 --seed 42 --collect_logprobs --output_dir output/fewnerd_t08_s42/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 42, \"gpu\": \"cuda:1\", \"tmux_session\": \"fewnerd_t08\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t08_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t08_s42/\"}, \"metrics\": {\"greedy_f1\": 0.7884, \"oracle_f1\": 0.875, \"oracle_headroom\": 0.0866, \"sample_f1_mean\": 0.6622, \"degeneracy_rate\": 0.1897, \"fleiss_kappa_mean\": 0.4439, \"soft_jaccard_mean\": 0.7572, \"rho_SJ_F1_full\": 0.2062, \"rho_SJ_F1_conditional\": 0.2248, \"rho_fleiss_F1_full\": 0.1038, \"rho_logprob_F1_full\": 0.2323, \"rho_logprob_F1_conditional\": 0.1984, \"structural_beats_surface\": true, \"rho_advantage\": 0.1024}, \"conclusion\": \"success\", \"notes\": \"T=0.8 confirms sweet-spot hypothesis on FewNERD: best rho_SJ_F1=0.206 (full), 0.225 (conditional), lowest degeneracy (19%), highest sample quality (mean F1=0.662). SJ beats Fleiss by 0.102 rho advantage. Logprob baseline rho=0.232 (full) surprisingly high — SJ diagnostic matches logprob informativeness at this T. Verdict FAIL only because MVP single-subtask threshold not met, but T=0.8 is clearly the best operating point.\", \"completed_at\": \"2026-05-21T00:45:13.333Z\"}, \"exp_fewnerd_t12_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:41:09.018Z\", \"updated_at\": \"2026-05-21T00:44:30.280Z\", \"hypothesis\": \"FewNERD temperature ablation (T=1.2): test how higher temperature affects degeneracy rate and SC diagnostic cascade on FewNERD, complementing SciERC T-ablation data. N=8, Qwen3-8B-FT, seed=42. Higher T should increase diversity and reduce degeneracy but degrade per-sample quality.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 1.2 --seed 42 --collect_logprobs --output_dir output/fewnerd_t12_s42/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged (Qwen3-8B-FT)\", \"seed\": 42, \"gpu\": \"cuda:2\", \"tmux_session\": \"fewnerd_t12\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/fewnerd_t12_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_t12_s42/\"}, \"metrics\": {\"greedy_f1\": 0.7888, \"oracle_f1\": 0.875, \"oracle_headroom\": 0.0862, \"sample_f1_mean\": 0.5524, \"degeneracy_rate\": 0.2818, \"fleiss_kappa_mean\": 0.283, \"soft_jaccard_mean\": 0.5894, \"rho_SJ_F1_full\": 0.136, \"rho_SJ_F1_conditional\": 0.2125, \"rho_fleiss_F1_full\": 0.0605, \"rho_logprob_F1_conditional\": 0.1912, \"structural_beats_surface\": true, \"rho_advantage\": 0.0755}, \"conclusion\": \"negative\", \"notes\": \"T=1.2 on FewNERD: high oracle headroom (8.6%) but poor SC diagnostic correlation (rho_SJ=0.136 full, 0.213 conditional). High degeneracy (28.2% zero-F1 samples) and low per-sample quality (mean F1=0.55) indicate T=1.2 over-diversifies. Structural metric (SJ) still beats surface (Fleiss) by 0.075 rho advantage. Verdict: FAIL (MVP threshold not met on single subtask).\", \"completed_at\": \"2026-05-21T00:44:30.280Z\"}, \"exp_conll_t12_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T23:41:59.173Z\", \"updated_at\": \"2026-05-21T00:39:01.179Z\", \"hypothesis\": \"CoNLL temperature ablation (T=1.2, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 1.2 --seed 123 --output_dir output/exp_conll_t12_seed123\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123}, \"metrics\": {\"greedy_f1\": 0.9072, \"oracle_f1\": 0.955, \"oracle_headroom\": 0.0478, \"fleiss_kappa_mean\": 0.6675, \"soft_jaccard_mean\": 0.8295, \"rho_fleiss_full\": 0.4086, \"rho_softjaccard_full\": 0.4352, \"rho_fleiss_cond\": 0.3516, \"rho_softjaccard_cond\": 0.3915, \"structural_beats_surface\": true, \"rho_advantage\": 0.0266, \"sample_f1_mean\": 0.8438, \"sample_f1_pct_zero\": 9.1, \"verdict\": \"PASS\"}, \"log_path\": \"output/exp_conll_t12_seed123.log\", \"checkpoint_path\": \"output/exp_conll_t12_seed123/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T00:39:01.179Z\"}, \"exp_conll_t08_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T23:41:58.169Z\", \"updated_at\": \"2026-05-21T00:38:55.958Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.8, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 0.8 --seed 123 --output_dir output/exp_conll_t08_seed123\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123}, \"metrics\": {\"greedy_f1\": 0.9068, \"oracle_f1\": 0.9466, \"oracle_headroom\": 0.0398, \"fleiss_kappa_mean\": 0.8246, \"soft_jaccard_mean\": 0.9201, \"rho_fleiss_full\": 0.4718, \"rho_softjaccard_full\": 0.4846, \"rho_fleiss_cond\": 0.4444, \"rho_softjaccard_cond\": 0.462, \"structural_beats_surface\": true, \"rho_advantage\": 0.0128, \"sample_f1_mean\": 0.8897, \"sample_f1_pct_zero\": 6.1, \"verdict\": \"PASS\"}, \"log_path\": \"output/exp_conll_t08_seed123.log\", \"checkpoint_path\": \"output/exp_conll_t08_seed123/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T00:38:55.958Z\"}, \"exp_conll_t05_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T23:41:56.932Z\", \"updated_at\": \"2026-05-21T00:38:53.249Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.5, seed=123): additional seed for statistical power, complementing seed=42 results. N=8, Qwen3-8B-FT, CoNLL-2003.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --n_samples 8 --temperature 0.5 --seed 123 --output_dir output/exp_conll_t05_seed123\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 123}, \"metrics\": {\"greedy_f1\": 0.9073, \"oracle_f1\": 0.9351, \"oracle_headroom\": 0.0278, \"fleiss_kappa_mean\": 0.8941, \"soft_jaccard_mean\": 0.954, \"rho_fleiss_full\": 0.4529, \"rho_softjaccard_full\": 0.4602, \"rho_fleiss_cond\": 0.4493, \"rho_softjaccard_cond\": 0.4566, \"structural_beats_surface\": true, \"rho_advantage\": 0.0072, \"sample_f1_mean\": 0.901, \"sample_f1_pct_zero\": 5.5, \"verdict\": \"PASS\"}, \"log_path\": \"output/exp_conll_t05_seed123.log\", \"checkpoint_path\": \"output/exp_conll_t05_seed123/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T00:38:53.249Z\"}, \"exp_qwen25_32b_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:19:25.428Z\", \"updated_at\": \"2026-05-21T00:18:28.126Z\", \"hypothesis\": \"Qwen2.5-32B-Instruct QLoRA fine-tuning on FewNERD: scaling model from 8B→32B should improve per-sample NER quality, enabling stronger SC diagnostic signals. LoRA r=32, alpha=64, target all attention+FFN projections, 5 epochs, 4×RTX 5090.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"started_at\": \"2026-05-19T06:47:41.246Z\"}, \"notes\": \"2026-05-19 11:36 UTC: step 2177/41180 (5.3%), loss 0.0663, ~2.44s/it, ETA ~26h. checkpoint-2000 saved. PID 804438, 4×5090 87-100% util.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0,1,2,3 FORCE_TORCHRUN=1 NNODES=1 NPROC_PER_NODE=4 llamafactory-cli train /root/autodl-tmp/struct_self_consist_ie/train_config_qwen25_32b_fewnerd_s42.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/llmfactory_train.json\", \"data_count\": 131767, \"model_name\": \"Qwen2.5-32B-Instruct\", \"seed\": 42, \"method\": \"QLoRA-4bit-nf4 (rank=32, alpha=64, target=all)\", \"output_dir\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-32b-fewnerd-qlora-s42\", \"config_path\": \"/root/autodl-tmp/struct_self_consist_ie/train_config_qwen25_32b_fewnerd_s42.yaml\", \"epochs\": 5, \"effective_batch_size\": 16, \"lr\": \"2e-4\", \"gpu_ids\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/train_qwen25_32b_fewnerd_s42.log\", \"pid\": 804438, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-32b-fewnerd-qlora-s42/checkpoint-32000\"}, \"metrics\": {\"total_steps\": 41180, \"epochs\": 5, \"best_checkpoint\": \"checkpoint-32000\", \"best_eval_loss\": 0.0334, \"final_train_loss\": 0.005, \"final_eval_loss\": 0.0412, \"initial_loss\": 0.559, \"training_time_hours\": 38.5, \"lora_rank\": 32, \"lora_alpha\": 64, \"note\": \"Overfitting after epoch ~3.9; best eval_loss at step 32000 (epoch 3.89). Post-training load-best-model OOM (rank2) but all checkpoints saved correctly.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T00:18:28.126Z\"}, \"exp_conll_t_ablation_t12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:41:01.169Z\", \"updated_at\": \"2026-05-20T23:35:53.499Z\", \"hypothesis\": \"CoNLL temperature ablation (T=1.2): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3-dataset temperature-degeneracy frontier. N=8, Qwen3-8B-FT, seed=42.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.2 --seed 42 --output_dir output/exp_conll_t12_seed42\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 2756, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42, \"pid\": 243594, \"gpu\": \"cuda:3\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t12_seed42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t12_seed42/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T23:35:37.422Z\", \"metrics\": {\"greedy_f1\": 0.9071, \"oracle_f1\": 0.9514, \"oracle_headroom\": 0.0443, \"fleiss_kappa\": 0.7092, \"softjaccard_rho_full\": 0.4071, \"softjaccard_rho_cond\": 0.3936, \"fleiss_rho_full\": 0.3786, \"fleiss_rho_cond\": 0.349, \"degen_pct\": 9.22, \"sample_f1_mean\": 0.8452, \"verdict\": \"PASS\"}}, \"exp_conll_t_ablation_t08\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:40:59.474Z\", \"updated_at\": \"2026-05-20T23:35:51.189Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.8): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3-dataset temperature-degeneracy frontier. N=8, Qwen3-8B-FT, seed=42.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.8 --seed 42 --output_dir output/exp_conll_t08_seed42\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 2756, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42, \"pid\": 242682, \"gpu\": \"cuda:2\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t08_seed42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t08_seed42/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T23:35:34.984Z\", \"metrics\": {\"greedy_f1\": 0.9069, \"oracle_f1\": 0.9464, \"oracle_headroom\": 0.0396, \"fleiss_kappa\": 0.8199, \"softjaccard_rho_full\": 0.4498, \"softjaccard_rho_cond\": 0.4373, \"fleiss_rho_full\": 0.4352, \"fleiss_rho_cond\": 0.4128, \"degen_pct\": 6.57, \"sample_f1_mean\": 0.8854, \"verdict\": \"PASS\"}}, \"exp_conll_t_ablation_t05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:40:58.068Z\", \"updated_at\": \"2026-05-20T23:35:48.803Z\", \"hypothesis\": \"CoNLL temperature ablation (T=0.5): test how temperature affects degeneracy rate and SC diagnostic cascade on CoNLL-2003, complementing SciERC and FewNERD T-ablation data to form 3-dataset temperature-degeneracy frontier. N=8, Qwen3-8B-FT, seed=42.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.5 --seed 42 --output_dir output/exp_conll_t05_seed42\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 2756, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42, \"pid\": 242197, \"gpu\": \"cuda:1\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t05_seed42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_conll_t05_seed42/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T23:35:32.179Z\", \"metrics\": {\"greedy_f1\": 0.9077, \"oracle_f1\": 0.9372, \"oracle_headroom\": 0.0296, \"fleiss_kappa\": 0.8948, \"softjaccard_rho_full\": 0.4312, \"softjaccard_rho_cond\": 0.4544, \"fleiss_rho_cond\": 0.4519, \"degen_pct\": 5.64, \"sample_f1_mean\": 0.8993, \"verdict\": \"PASS\"}}, \"exp_conll_t05_s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:41:11.361Z\", \"updated_at\": \"2026-05-20T23:35:46.566Z\", \"hypothesis\": \"CoNLL T=0.5 temperature point: test low temperature on CoNLL2003 to extend cross-dataset T-ablation evidence beyond SciERC and FewNERD. N=8, Qwen3-8B-FT-CoNLL, seed=42. Complements SciERC T-ablation for 3-dataset degeneracy-temperature comparison.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003/ --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.5 --seed 42 --collect_logprobs --output_dir output/conll_t05_s42/\", \"server\": \"autodl-5090-b\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003/test.json\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged (Qwen3-8B-FT-CoNLL)\", \"seed\": 42, \"gpu\": \"cuda:3\", \"tmux_session\": \"conll_t05\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/conll_t05_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/conll_t05_s42/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T23:35:29.767Z\", \"metrics\": {\"greedy_f1\": 0.9083, \"oracle_f1\": 0.9376, \"oracle_headroom\": 0.0294, \"fleiss_kappa\": 0.8958, \"softjaccard_rho_full\": 0.4228, \"softjaccard_rho_cond\": 0.4476, \"fleiss_rho_cond\": 0.4443, \"logprob_rho_cond\": 0.3562, \"logprob_auroc_cond\": 0.8102, \"degen_pct\": 5.64, \"sample_f1_mean\": 0.8994, \"verdict\": \"PASS\"}}, \"exp_spider_sc_pilot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T18:41:49.560Z\", \"updated_at\": \"2026-05-20T22:37:08.907Z\", \"hypothesis\": \"SC diagnostic cascade (degeneracy, agreement-correctness correlation, failure mode classification F1-F4) validated on NER structured generation will also manifest in SQL structured generation with GPT-5.5 on Spider-dev (200 examples, N=8, T=1.0), demonstrating cross-task universality. Key adaptation: uses execution-result equivalence (not SQL text) for agreement/degeneracy, since semantically equivalent SQL can have different surface forms.\", \"spec\": {\"command\": \"python run_spider_sc.py --n_samples 8 --temperature 1.0 --seed 42 --output_dir ./results --test_api\", \"server\": \"local (CPU+API)\", \"gpu\": \"cuda:2\", \"data_path\": \"xlangai/spider (HF) + spider databases (sqlite)\", \"data_count\": 200, \"model_name\": \"openai/gpt-5.5 via http://47.94.22.126/v1\", \"seed\": 42, \"bugfixes\": [\"F1-F4 failure modes aligned with NER cascade (F2=low_agreement, F3=high_agreement_wrong)\", \"Degeneracy detection uses execution results instead of SQL text comparison\", \"Converted from vLLM to API-based (CPU+API experiment)\"], \"pid\": 1504303, \"failure_reason\": \"402 API balance exhausted at 125/200 instances\", \"partial_results\": \"125/200 instances completed before API died\", \"log_path\": \"local spider_sc results dir\", \"checkpoint_path\": \"local spider_sc results dir\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T22:05:14.976Z\", \"metrics\": {\"n_instances\": 196, \"n_target\": 200, \"n_skipped\": 2, \"n_samples\": 8, \"temperature\": 1, \"model\": \"gpt-5.5\", \"greedy_acc\": 0.7653, \"mv_acc\": 0.7704, \"oracle_acc\": 0.8061, \"mv_gain_pp\": 0.51, \"degeneracy_rate\": 0.8724, \"spearman_rho\": 0.5501, \"spearman_p\": 6.77e-17, \"kendall_tau\": 0.5259, \"F1_degeneracy_rate\": 0.872, \"F2_low_agreement_rate\": 0, \"F3_high_agree_wrong_rate\": 0.082, \"F4_selection_gap_rate\": 0, \"sc_success_rate\": 0.046, \"nondegen_n\": 25, \"nondegen_greedy_acc\": 0.32, \"nondegen_mv_acc\": 0.36, \"nondegen_oracle_acc\": 0.64, \"nondegen_spearman_rho\": 0.13}, \"notes\": \"Data quality verified: all 196 instances generated AFTER F2/F3 bugfix (code modified 20:47:22, checkpoint started 20:47:52). Zero mismatch between embedded and recomputed failure modes. F1-F4 distribution: F1=87.2%, F2=0%, F3=8.2%, F4=0%, OK=4.6%. F2=0 means SQL has no low-agreement zone (either degenerate or high consensus). Paper-ready. Note: F4 is dead code in SQL context (greedy_correct AND NOT mv_correct never occurs). Cross-task threshold note: SQL uses agreement<0.5 for F2/F3 split, RE uses kappa<0.3.\"}, \"exp_fewrel_re_sc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T21:13:10.685Z\", \"updated_at\": \"2026-05-20T22:08:51.973Z\", \"hypothesis\": \"SC consensus construction improves RE micro-F1 over greedy decoding on FewRel (16 relation types, Wikipedia domain), extending cross-task universality evidence beyond SciERC and DocRED\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python3 -u experiments/fewrel_re_sc/run_fewrel_re_sc.py --model-path /root/autodl-tmp/.hf_cache/Qwen2.5-7B-Instruct --data data/fewrel_re_test_instances.jsonl --output-dir output/fewrel_re_sc --n-samples 8 --temperature 1.0\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewrel_re_test_instances.jsonl\", \"data_count\": 256, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"pid\": 236752, \"gpu\": \"cuda:1\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewrel_re_sc/run.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewrel_re_sc/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T21:20:24.473Z\", \"metrics\": {\"greedy_micro_f1\": 0.0751, \"construction_micro_f1\": 0.0881, \"majority_vote_f1_mean\": 0.0591, \"oracle_f1_mean\": 0.1768, \"fleiss_kappa_mean\": 0.1506, \"soft_jaccard_mean\": 0.3918, \"degeneracy_rate\": 0.0586, \"bootstrap_p_value\": 0.7572, \"failure_modes\": {\"F2_low_agreement\": \"75.8%\", \"F3_high_agreement_low_quality\": \"15.2%\", \"F1_degeneracy\": \"5.9%\", \"none\": \"2.3%\", \"F4_lp_quality_gap\": \"0.8%\"}}, \"notes\": \"Reviewer confirmed: same pattern as SciERC/DocRED RE (low F1, high F2). Micro_f1 and mean_f1 directions diverge: construction micro_f1 > greedy (0.0881 vs 0.0751) but mean_f1 < greedy. Paper uses micro_f1 per D204. Marked negative because bootstrap p=0.7572 (not significant).\"}, \"exp_a2_humaneval_sc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T18:15:14.615Z\", \"updated_at\": \"2026-05-20T22:05:17.728Z\", \"hypothesis\": \"SC failure modes (degeneracy, false agreement) generalize from NER to code generation despite deterministic verification — majority voting on HumanEval will show limited gains over greedy when degeneracy is high, paralleling NER findings.\", \"spec\": {\"command\": \"python -u run_humaneval_sc.py --n_samples 8 --temperature 1.0 --seed 42 --output_dir ./results\", \"server\": \"autodl-5090\", \"pid\": 967645, \"data_path\": \"openai/openai_humaneval (HuggingFace)\", \"data_count\": 164, \"model_name\": \"openai/gpt-5.5\", \"seed\": 42, \"fix_note\": \"v2 rerun: fixed extract_code() strip() -> rstrip() + auto-indent for function body. Previous run had 0/164 pass due to IndentationError.\", \"failure_reason\": \"402 API balance exhausted after indent bugfix. Fix verified (23/23 greedy pass, 179/184 sample pass) but only 24/164 tasks completed before API died.\", \"log_path\": \"autodl-5090 humaneval results dir\", \"checkpoint_path\": \"autodl-5090 humaneval results dir\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-20T22:05:17.728Z\"}, \"exp_b_frontier_sc_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T18:15:19.266Z\", \"updated_at\": \"2026-05-20T22:05:12.564Z\", \"hypothesis\": \"The correlation-selection gap in structured self-consistency (where agreement correlates with accuracy but majority voting fails to improve over greedy) persists even with frontier models (GPT-5.5, Claude Opus 4.6), indicating it is a fundamental structural limitation of entity-level majority voting rather than a model capability issue.\", \"spec\": {\"command\": \"nohup .venv/bin/python -u run_frontier_sc.py --from-hf --n-instances 200 --n-samples 8 --temperature 1.0 --seed 42 --output-dir ./output > frontier_sc.log 2>&1 &\", \"server\": \"local\", \"data_path\": \"HuggingFace DFKI-SLT/few-nerd supervised test split\", \"data_count\": 200, \"model_name\": \"openai/gpt-5.5 + anthropic/claude-opus-4.6 (via OpenRouter)\", \"seed\": 42, \"pid\": 1509955, \"code_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/experiments/frontier_sc/run_frontier_sc.py\", \"log_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/experiments/frontier_sc/frontier_sc.log\", \"checkpoint_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/experiments/frontier_sc/output/\", \"failure_reason\": \"entity_set() TypeError - compute_instance_metrics passed full parsed dict instead of entities list\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-20T22:05:12.564Z\"}, \"exp_docred_re_sc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T19:32:26.943Z\", \"updated_at\": \"2026-05-20T21:07:53.274Z\", \"hypothesis\": \"SC diagnostic cascade (degeneracy, correlation-selection gap, F1-F4 failure modes) generalizes from NER to document-level RE on DocRED, with Qwen2.5-7B-Instruct showing similar failure patterns as seen in SciERC NER and SciERC RE.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python3 experiments/docred_re/run_docred_re_sc.py --model-path /root/autodl-tmp/.hf_cache/Qwen2.5-7B-Instruct --data data/docred_re_instances.jsonl --schema data/docred_schema.json --output-dir output/docred_re_sc\", \"server\": \"autodl-5090-c\", \"data_path\": \"data/docred_re_instances.jsonl\", \"data_count\": 200, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/docred_re_sc/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/docred_re_sc/run.log\"}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"metrics\": {\"greedy_f1_mean\": 0.0284, \"construction_f1_mean\": 0.0338, \"majority_vote_f1_mean\": 0.0263, \"oracle_f1_mean\": 0.0999, \"greedy_micro_f1\": 0.0297, \"construction_micro_f1\": 0.0323, \"fleiss_kappa\": -0.0253, \"soft_jaccard\": 0.2907, \"degeneracy_rate\": 0.035, \"n_instances\": 200, \"failure_modes\": {\"F1_degeneracy\": \"3.5%\", \"F2_low_agreement\": \"94.5%\", \"F3_high_agreement_low_quality\": \"2.0%\"}, \"bootstrap_diff\": 0.0053, \"bootstrap_ci_95\": [-0.004, 0.0149], \"bootstrap_p_value\": 0.1276, \"nondegen_construction_greedy_diff\": 0.0055}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T21:07:53.274Z\"}, \"exp_a3_ace05_re\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T18:15:17.438Z\", \"updated_at\": \"2026-05-20T21:03:51.597Z\", \"hypothesis\": \"Cross-task universality: SC diagnostic cascade on ACE05 Relation Extraction. Closest extension to NER—same structured prediction paradigm, different output structure (entity pairs + relation types). Qwen2.5-7B-Instruct few-shot prompt. If correlation-selection gap exists for RE, the framework covers multiple IE sub-tasks.\", \"spec\": {\"hypothesis\": \"The SC diagnostic cascade (degeneracy, agreement, LP-quality gap) generalizes from NER to Relation Extraction, with failure modes F1-F4 exhibiting analogous distributions on RE because both are span-based structured prediction tasks sharing the same underlying model uncertainty structure.\", \"model_name\": \"Qwen2.5-7B-Instruct\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/re_test_instances.jsonl\", \"data_count\": 397, \"server\": \"autodl-5090-c\", \"seed\": 42, \"command\": \"CUDA_VISIBLE_DEVICES=1 python3 experiments/re_sc/run_re_sc.py --model-path /root/autodl-tmp/.hf_cache/Qwen2.5-7B-Instruct --data data/re_test_instances.jsonl --output-dir output/re_sc --n-samples 8 --temperature 1.0\", \"method\": \"SC diagnostic cascade on RE (few-shot, N=8, T=1.0, XGrammar constrained decoding)\", \"parent\": null, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/re_sc/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/re_sc.log\"}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T21:03:46.444Z\", \"metrics\": {\"greedy_f1_mean\": 0.0777, \"construction_f1_mean\": 0.0599, \"majority_vote_f1_mean\": 0.0491, \"oracle_f1_mean\": 0.1567, \"greedy_micro_f1\": 0.0688, \"construction_micro_f1\": 0.0602, \"fleiss_kappa\": -0.0021, \"soft_jaccard\": 0.2425, \"degeneracy_rate\": 0.0076, \"n_instances\": 397, \"failure_modes\": {\"F1_degeneracy\": \"0.8%\", \"F2_low_agreement\": \"93.5%\", \"F3_high_agreement_low_quality\": \"4.5%\", \"none\": \"1.3%\"}, \"bootstrap_diff\": -0.0178, \"bootstrap_ci_95\": [-0.0334, -0.0024], \"bootstrap_p_value\": 0.989}}, \"exp_b1_scd_fewnerd_curriculum_q\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:17:38.760Z\", \"updated_at\": \"2026-05-20T20:15:55.005Z\", \"hypothesis\": \"Q variant SCD with curriculum ordering: use B2 entity verifier confidence to stratify pseudo-labels (conf>0.8→Round1, 0.5-0.8→Round2, conf<0.5→discard). Curriculum by verifier confidence improves SCD convergence and final greedy F1 vs standard flat SCD on FewNERD.\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scd_fewnerd_fallback_s43.yaml\", \"server\": \"autodl-5090-b\", \"gpu_ids\": [1], \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scd_fewnerd_theta2n_s42.jsonl\", \"data_count\": 32565, \"model_name\": \"Qwen3-8B-FT\", \"seed\": 43, \"note\": \"Fallback standard SCD seed=43 (Q-variant deferred per D189)\"}, \"reproduce\": {\"finished_at\": \"2026-05-20T19:01:52.441Z\"}, \"failure_reason\": \"RETRACTED: cron false positive — training completed successfully (4706/4706 steps, loss=0.023). Original: process dead 5× with no sentinel/W&B\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T19:01:57.213Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T19:02:06.612980+00:00\"}]}, \"notes\": \"M046: SCD metric artifact confirmed. Original +3.84pp was comparing instance-avg F1 baseline (0.7482, gold-filtered n=32565) to micro-F1 post-SCD (0.7866, full n=37648). Unified micro-F1: pre=0.7886 → post=0.7866, Δ=-0.20pp. Instance-avg: pre=0.7719 → post=0.7809, Δ=+0.90pp (much smaller than claimed). SCD does not constitute paper contribution.\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-scd-fallback-lora/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp_b1_scd_fewnerd_fallback.log\", \"metrics\": {\"eval_greedy_f1\": 0.7866, \"eval_greedy_precision\": 0.7663, \"eval_greedy_recall\": 0.808, \"eval_instance_avg_f1\": 0.7809, \"delta_vs_baseline\": 0.0386, \"baseline_greedy_f1\": 0.748, \"total_tp\": 78252, \"total_fp\": 23869, \"total_fn\": 18590, \"n_instances\": 37648}}, \"exp_b1_scd_fewnerd_standard\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:17:37.804Z\", \"updated_at\": \"2026-05-20T20:15:51.708Z\", \"hypothesis\": \"Standard Self-Consistency Distillation on FewNERD: fine-tune Qwen3-8B-FT with theta2n construction pseudo-labels (32,565 instances) mixed 1:1 with gold data. Greedy F1 after SCD should approach N=8 construction F1 (0.764 vs current 0.748). Transductive setting: pseudo-labels from test set SC outputs.\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scd_fewnerd_s42.yaml\", \"server\": \"autodl-5090-b\", \"gpu_ids\": [0], \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scd_fewnerd_theta2n_s42.jsonl\", \"data_count\": 32565, \"model_name\": \"Qwen3-8B-FT\", \"seed\": 42, \"pid\": 207109, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-fewnerd-scd-lora/\"}, \"reproduce\": {\"finished_at\": \"2026-05-20T19:13:25.333Z\"}, \"failure_reason\": \"RETRACTED: cron false positive — training completed successfully (4706/4706 steps, train_loss=0.023, eval_loss=0.0329). Original: process dead 5× with no sentinel/W&B\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T19:13:26.395Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T19:13:35.804759+00:00\"}]}, \"notes\": \"M046: SCD metric artifact confirmed. Original +3.3pp was comparing instance-avg F1 baseline (0.7482, gold-filtered n=32565) to micro-F1 post-SCD (0.7813, full n=37648). Unified micro-F1: pre=0.7886 → post=0.7813, Δ=-0.73pp. SCD does not improve NER performance.\", \"metrics\": {\"train_loss\": 0.023, \"eval_loss\": 0.0329, \"steps\": 4706, \"epochs\": 2, \"train_runtime_hours\": 7.14}}, \"exp_b1_scd_threshold_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:17:42.163Z\", \"updated_at\": \"2026-05-20T20:00:50.883Z\", \"hypothesis\": \"Construction threshold sweep for SCD pseudo-label generation on FewNERD: θ∈{1/N, 2/N, 3/N, 0.5}. Higher θ = more conservative pseudo-labels (higher precision, lower recall). Optimal θ balances pseudo-label quality vs quantity for SCD training effectiveness.\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scd_fewnerd_theta3_s42.yaml\", \"server\": \"autodl-5090-b\", \"gpu_ids\": [3], \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scd_fewnerd_theta3n_s42.jsonl\", \"data_count\": 32565, \"model_name\": \"Qwen3-8B-FT\", \"seed\": 42, \"note\": \"theta=3/N ablation\"}, \"reproduce\": {\"finished_at\": \"2026-05-20T20:00:47.950Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-20T20:00:50.883Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T20:00:57.832218+00:00\"}]}}, \"exp_tlow_fewnerd_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:40:52.432Z\", \"updated_at\": \"2026-05-20T19:39:38.613Z\", \"hypothesis\": \"Lower temperature (T=0.5) sampling on FewNERD produces less diverse but higher-quality samples that, when combined with T=1.0 samples in heterogeneous-temperature selection, improve self-consistency-based quality estimation compared to single-temperature baselines.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen25-7b-fewnerd-merged --data_dir data/fewnerd/ --dataset fewnerd --subtask ner --n_samples 8 --temperature 0.5 --seed 42 --collect_logprobs --output_dir output/exp_tlow_fewnerd_t05_s42/\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 37648, \"model_name\": \"qwen25-7b-fewnerd-merged\", \"seed\": 42, \"pid\": 221493, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_tlow_fewnerd_t05_s42.log\"}, \"checkpoint_path\": \"output/exp_tlow_fewnerd_t05_s42/\", \"log_path\": \"output/exp_tlow_fewnerd_t05_s42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T19:39:38.613Z\"}, \"exp_asb_adaptive_budget\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:37:33.233Z\", \"updated_at\": \"2026-05-20T19:37:37.412Z\", \"hypothesis\": \"Instance-level features from cheap N=2 subsamples (degeneracy, agreement, entity count, logprob variance, text length) can predict optimal per-instance sample count, enabling adaptive budget allocation that outperforms uniform allocation under a fixed total budget.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python /root/autodl-tmp/struct_self_consist_ie/artifacts/experiments/asb/run_asb.py --data_paths /root/autodl-tmp/struct_self_consist_ie/output/exp_021_inference/samples.jsonl,/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed42/samples.jsonl,/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16/samples.jsonl --dataset_names FewNERD,SciERC,CoNLL --output_dir /root/autodl-tmp/struct_self_consist_ie/output/exp_asb_adaptive_budget/ --seed 42\\\"\", \"server\": \"autodl-5090\", \"gpu\": [], \"pid\": \"943151\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_asb_adaptive_budget.log\", \"submitted_at\": \"2026-05-20T17:55:06.477Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"output/exp_asb_adaptive_budget/asb_results.json\", \"wall_clock_seconds\": 215.1, \"gpu_hours\": 0.0}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T17:58:41.592Z\", \"metrics\": {\"v2_fixed\": true, \"fixes\": [\"removed greedy_f1 feature (data leak via gold labels)\", \"max_n-aware adaptive_allocation\", \"K-fold downstream eval (no train=test leak)\", \"micro-F1 (global TP/FP/FN)\"], \"fewnerd\": {\"uniform_n8_micro_f1\": 0.7842, \"adaptive_micro_f1\": 0.7842, \"delta_adaptive_uniform\": 0, \"oracle_micro_f1\": 0.7842, \"greedy_micro_f1\": 0.7911, \"best_predictor\": \"MLP\", \"n_instances\": 32565, \"max_n\": 8, \"note\": \"max_n=budget=8, no room for reallocation\"}, \"scierc\": {\"uniform_n8_micro_f1\": 0.6657, \"adaptive_micro_f1\": 0.6657, \"delta_adaptive_uniform\": 0, \"oracle_micro_f1\": 0.6657, \"greedy_micro_f1\": 0.6649, \"best_predictor\": \"MLP\", \"n_instances\": 529, \"max_n\": 8, \"note\": \"max_n=budget=8, no room for reallocation\"}, \"conll\": {\"uniform_n8_micro_f1\": 0.9128, \"adaptive_micro_f1\": 0.9095, \"delta_adaptive_uniform\": -0.0033, \"oracle_micro_f1\": 0.9139, \"delta_oracle_uniform\": 0.0012, \"greedy_micro_f1\": 0.9124, \"adaptive_fold_mean\": 0.91, \"adaptive_fold_std\": 0.0044, \"best_predictor\": \"RandomForest\", \"n_instances\": 2756, \"max_n\": 16}, \"top_features\": [\"degen_rate_n2\", \"agreement_n2\", \"entity_count_n2\"], \"key_finding\": \"After fixing data leak + train=test leak + max_n bug, adaptive allocation shows no improvement over uniform. FewNERD/SciERC have max_n=budget=8 (no reallocation possible). CoNLL (max_n=16) shows slight negative delta (-0.0033). Previous positive results were artifacts of methodological bugs.\"}}, \"exp_e_theta_adaptive\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:31:49.319Z\", \"updated_at\": \"2026-05-20T19:24:52.991Z\", \"hypothesis\": \"Threshold-Adaptive SC: N inverse scaling (D191) proves θ choice determines scaling direction. A learned θ predictor (input: degeneracy_level, lp_variance, N, dataset, model) can select per-instance optimal θ, closing the gap between fixed θ=0.5 and oracle θ. Leave-one-config-out CV on 16 configs from existing N=8/16 data. 5 variants: LogReg/MLP × feature subsets + degeneracy-only baseline.\", \"spec\": {\"checkpoint_path\": \"N/A (CPU predictor, no model checkpoint)\", \"log_path\": \"N/A (inline evaluation)\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T19:24:52.991Z\"}, \"exp_cross_model_consistency\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T09:30:47.928Z\", \"updated_at\": \"2026-05-20T19:03:33.786Z\", \"hypothesis\": \"Cross-model entity construction (mixing Qwen and LLaMA outputs) produces higher-quality entity spans than single-model construction, because inter-model agreement filters out model-specific hallucinations while preserving genuinely supported entities.\", \"metrics\": {\"scierc\": {\"n_filtered\": 529, \"qwen_greedy_f1\": 0.6453, \"llama_greedy_f1\": 0.646, \"degeneracy\": {\"pure_qwen\": 0.1323, \"pure_llama\": 0.1777, \"mixed\": 0.0964}, \"construction_f1\": {\"pure_qwen_uniform\": 0.6449, \"pure_qwen_vc\": 0.6413, \"pure_llama_uniform\": 0.6545, \"pure_llama_vc\": 0.649, \"mixed_uniform\": 0.6625, \"mixed_vc\": 0.6591}, \"bootstrap\": {\"mixed_uni_vs_pure_qwen_uni\": {\"delta_pp\": 1.77, \"p\": 0.0102, \"ci\": [0.27, 3.28]}, \"mixed_vc_vs_pure_qwen_vc\": {\"delta_pp\": 1.77, \"p\": 0.0093, \"ci\": [0.33, 3.27]}, \"mixed_uni_vs_pure_llama_uni\": {\"delta_pp\": 0.81, \"p\": 0.1304, \"ci\": [-0.59, 2.25]}, \"mixed_vc_vs_pure_llama_vc\": {\"delta_pp\": 1.01, \"p\": 0.0702, \"ci\": [-0.32, 2.38]}}}, \"fewnerd\": {\"n_filtered\": 32565, \"qwen_greedy_f1\": 0.7478, \"llama_greedy_f1\": 0.7841, \"degeneracy\": {\"pure_qwen\": 0.1004, \"pure_llama\": 0.2336, \"mixed\": 0.1158}, \"construction_f1\": {\"pure_qwen_uniform\": 0.7499, \"pure_qwen_vc\": 0.7448, \"pure_llama_uniform\": 0.7873, \"pure_llama_vc\": 0.7869, \"mixed_uniform\": 0.7916, \"mixed_vc\": 0.7898}, \"bootstrap\": {\"mixed_uni_vs_pure_qwen_uni\": {\"delta_pp\": 4.17, \"p\": 0, \"ci\": [3.92, 4.4]}, \"mixed_vc_vs_pure_qwen_vc\": {\"delta_pp\": 4.5, \"p\": 0, \"ci\": [4.25, 4.75]}, \"mixed_uni_vs_pure_llama_uni\": {\"delta_pp\": 0.42, \"p\": 0, \"ci\": [0.27, 0.58]}, \"mixed_vc_vs_pure_llama_vc\": {\"delta_pp\": 0.29, \"p\": 0.0001, \"ci\": [0.13, 0.45]}}}}, \"conclusion\": \"success\", \"notes\": \"B5 cross-model consistency on SciERC + FewNERD. Mixed (4Q+4L) consistently outperforms pure-model construction on both datasets. FewNERD: mixed sig. beats pure LLaMA (+0.42pp uni p=0, +0.29pp VC p=0.0001) and pure Qwen (+4.17pp uni, +4.50pp VC, all p=0). SciERC: mixed sig. beats pure Qwen (+1.77pp uni p=0.01, +1.77pp VC p=0.009); vs pure LLaMA marginal (+0.81pp uni p=0.13, +1.01pp VC p=0.07). Cross-model diversity reduces degeneracy (FewNERD mixed 11.6% vs LLaMA 23.4%; SciERC mixed 9.6% vs LLaMA 17.8%). Note: SciERC greedy F1 lower than prior run (0.645 vs 0.748) — likely different eval scope (gold filter 529 vs prior 551).\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"spec\": {\"command\": \"bash code/run_cross_model.sh\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_026_t10_seed42/samples.jsonl + output/exp007_llama_inference/samples.jsonl + output/exp_021_inference/samples.jsonl + output/llama_fewnerd_s42/samples.jsonl\", \"data_count\": 76398, \"model_name\": \"cross-model (Qwen + LLaMA)\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_cross_model_consistency\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_cross_model_consistency\"}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_cross_model_consistency\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_cross_model_consistency\", \"completed_at\": \"2026-05-20T19:03:33.786Z\"}, \"exp_backup3_distill_verifier\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:40:49.676Z\", \"updated_at\": \"2026-05-20T18:47:37.248Z\", \"hypothesis\": \"A supervised entity-level binary classifier (trained on 6 lightweight features: LP score, agreement ratio, degeneracy flag, span length, type consistency, N) can learn cross-dataset entity correctness signals that outperform unsupervised majority voting for entity construction, because the classifier can jointly weight multiple complementary signals that MV ignores.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python /root/autodl-tmp/struct_self_consist_ie/run_distill_verifier.py --seed 42\", \"server\": \"autodl-5090\", \"data_path\": {\"scierc\": \"output/exp_026_t10_seed42/samples.jsonl (551 inst, N=8)\", \"conll\": \"output/exp_002_conll_n16/samples.jsonl (3453 inst, N=16→subsample to 8)\", \"fewnerd\": \"output/exp_021_inference/samples.jsonl (37648 inst, N=8)\"}, \"data_count\": \"41652 instances total (~551+3453+37648)\", \"model_name\": \"LR+RF+MLP ensemble (sklearn)\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/distill_verifier/distill_verifier_results.json\", \"log_path\": \"/tmp/distill_verifier.log\", \"completed_at\": \"2026-05-20T18:47:30.099Z\", \"metrics\": {\"aggregate\": {\"LR\": {\"mean_auroc\": 0.8747, \"std_auroc\": 0.0563, \"mean_delta_f1\": -0.0014}, \"RF\": {\"mean_auroc\": 0.8752, \"std_auroc\": 0.0588, \"mean_delta_f1\": -0.0006}, \"MLP\": {\"mean_auroc\": 0.8744, \"std_auroc\": 0.0578, \"mean_delta_f1\": 0.0011}}, \"per_fold\": {\"scierc\": {\"LR\": {\"auroc\": 0.8009, \"std_mv_f1\": 0.6643, \"best_weighted_f1\": 0.6659, \"delta_f1\": 0.0016}, \"RF\": {\"auroc\": 0.7988, \"best_weighted_f1\": 0.6647, \"delta_f1\": 0.0004}, \"MLP\": {\"auroc\": 0.798, \"best_weighted_f1\": 0.6655, \"delta_f1\": 0.0012}}, \"conll\": {\"LR\": {\"auroc\": 0.9376, \"std_mv_f1\": 0.9074, \"best_weighted_f1\": 0.9049, \"delta_f1\": -0.0025}, \"RF\": {\"auroc\": 0.9419, \"best_weighted_f1\": 0.908, \"delta_f1\": 0.0006}, \"MLP\": {\"auroc\": 0.9379, \"best_weighted_f1\": 0.9075, \"delta_f1\": 0.0001}}, \"fewnerd\": {\"LR\": {\"auroc\": 0.8855, \"std_mv_f1\": 0.7819, \"best_weighted_f1\": 0.7786, \"delta_f1\": -0.0034}, \"RF\": {\"auroc\": 0.885, \"best_weighted_f1\": 0.7791, \"delta_f1\": -0.0029}, \"MLP\": {\"auroc\": 0.8872, \"best_weighted_f1\": 0.7839, \"delta_f1\": 0.002}}}, \"feature_importance_LR_scierc\": {\"agreement_ratio\": 1.651, \"lp_score\": 0.424, \"span_length\": -0.15, \"type_consistency\": 0.128, \"degeneracy_flag\": 0.043, \"n_samples\": 0}}}, \"exp_backup1_het_temp\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:09:31.094Z\", \"updated_at\": \"2026-05-20T18:15:37.574Z\", \"hypothesis\": \"Heterogeneous-Temperature Sampling: MRSC/LSC negative results prove entity-level correction cannot close the selection gap. F4 degeneracy analysis shows T=0.7 has ~62% degeneracy (too homogeneous) while T=1.0 has more diversity but noisier entities. Mixing samples from different temperatures (k from T_low + (8-k) from T_high) breaks temperature-specific degeneracy patterns: low-T samples provide precise entities, high-T samples provide diversity. Mixed-T N=8 pool should achieve lower degeneracy than pure T_low and higher construction F1 than pure T_high. Hypothesis source: entity-level methods (MRSC weighted re-prompting, LSC latent aggregation) both failed → pivot to sampling-level diversity improvement.\", \"parent\": \"exp_mrsc_multi_round\", \"spec\": {\"command\": \"bash /root/autodl-tmp/struct_self_consist_ie/run_het_temp_all.sh\", \"server\": \"autodl-5090\", \"gpu\": [], \"pid\": \"948780\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_backup1_het_temp.log\", \"submitted_at\": \"2026-05-20T18:13:20.732Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 134.1, \"gpu_hours\": 0.0}, \"metrics\": {\"t08_vs_t10\": {\"seed42\": {\"pure_t_low_f1\": 0.6755, \"pure_t_high_f1\": 0.6643, \"best_mix\": \"5:3\", \"best_mix_f1\": 0.6708, \"delta_vs_low\": -0.0046, \"delta_vs_high\": 0.0066}, \"seed123\": {\"pure_t_low_f1\": 0.6659, \"pure_t_high_f1\": 0.6681, \"best_mix\": \"6:2\", \"best_mix_f1\": 0.6655, \"delta_vs_low\": -0.0004, \"delta_vs_high\": -0.0026}, \"seed456\": {\"pure_t_low_f1\": 0.6675, \"pure_t_high_f1\": 0.6663, \"best_mix\": \"4:4\", \"best_mix_f1\": 0.6654, \"delta_vs_low\": -0.002, \"delta_vs_high\": -0.0008}}, \"t05_vs_t10\": {\"seed42\": {\"pure_t_low_f1\": 0.663, \"pure_t_high_f1\": 0.6643, \"best_mix\": \"5:3\", \"best_mix_f1\": 0.6654, \"delta_vs_low\": 0.0024, \"delta_vs_high\": 0.0011}, \"seed123\": {\"pure_t_low_f1\": 0.6665, \"pure_t_high_f1\": 0.6681, \"best_mix\": \"2:6\", \"best_mix_f1\": 0.6671, \"delta_vs_low\": 0.0006, \"delta_vs_high\": -0.001}, \"seed456\": {\"pure_t_low_f1\": 0.6686, \"pure_t_high_f1\": 0.6663, \"best_mix\": \"4:4\", \"best_mix_f1\": 0.6682, \"delta_vs_low\": -0.0004, \"delta_vs_high\": 0.002}}, \"degeneracy\": {\"t05_mean\": 0.356, \"t08_mean\": 0.178, \"t10_mean\": 0.126}, \"max_delta_any_combo\": 0.0066}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T18:15:34.876Z\", \"notes\": \"Heterogeneous temperature mixing provides no consistent F1 improvement over pure single-temperature sampling on SciERC (551 instances, 3 seeds, 2 temp pairs). All F1 deltas within ±0.005, inconsistent direction across seeds. Mixing does reduce degeneracy (T=0.5: 35%→17%) but this doesn't translate to F1 gain. The pure T_low vs T_high F1 gap is already tiny (~0.001-0.01), leaving no room for mixing to exploit. Joins MRSC/LSC as evidence that sampling-level interventions cannot improve construction F1 when the bottleneck is not sample diversity.\"}, \"exp_esj_entity_self_judgment\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:31:53.721Z\", \"updated_at\": \"2026-05-20T17:44:33.778Z\", \"hypothesis\": \"Entity-Level Self-Judgment: F4 diagnostic proves 4/5 signals are instance-level only, LP is per-sample but compressed. ESJ provides true per-sample-per-entity signal via yes/no verification prompts. ESJ-weighted entity construction should outperform majority vote by leveraging entity-level confidence scores that structural signals cannot provide. Parent: exp_e2_mixture_of_signals (F4 LP-only diagnostic).\", \"parent\": \"exp_e2_mixture_of_signals\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-20T15:37:30.954Z\"}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python run_esj.py --base_model_path checkpoints/qwen25-7b-fewnerd-merged --data_path output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl --output_dir output/exp_esj_entity_self_judgment --batch_size 8\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl\", \"data_count\": 37648, \"model_name\": \"qwen25-7b-fewnerd-merged\", \"seed\": 42, \"pid\": 218678, \"gpu\": \"cuda:1\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_esj_entity_self_judgment.log\", \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-fewnerd-merged\", \"eval_data\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl\", \"n_verification_prompts\": 153649, \"estimated_runtime_hours\": 2.5, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_esj_entity_self_judgment/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T17:44:33.778Z\"}, \"exp_b3_prompted_diversity\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:12:51.750Z\", \"updated_at\": \"2026-05-20T17:40:45.878Z\", \"hypothesis\": \"Structurally different prompt templates (expert persona, descriptive types, recall-focused) generate more diverse N=8 samples than repeating a single template, improving entity construction F1 via broader coverage of the entity space.\", \"conclusion\": \"killed\", \"metrics\": {\"single_vc_weighted_f1\": 0.7723, \"multi_vc_weighted_f1\": 0.7311, \"delta_vc\": -0.0412, \"single_lp_weighted_f1\": 0.7665, \"multi_lp_weighted_f1\": 0.7308, \"delta_lp\": -0.0356, \"single_theta2n_f1\": 0.7618, \"multi_theta2n_f1\": 0.7269, \"delta_theta2n\": -0.0349, \"single_unique_entities\": 5.29, \"multi_unique_entities\": 4.06, \"within_template_jaccard\": 0.474, \"cross_template_jaccard\": 0.67, \"verdict\": \"Multi-template strictly worse. Templates converge to similar outputs; non-standard templates add noise, diluting construction signals.\"}, \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python /root/autodl-tmp/struct_self_consist_ie/code/exp_b3_prompted_diversity.py --phase both --num_instances 3000 --seed 42\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/test.json\", \"data_count\": 3000, \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"completed_at\": \"2026-05-20T17:40:45.878Z\"}, \"exp_mrsc_multi_round\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:37:27.523Z\", \"updated_at\": \"2026-05-20T17:12:53.641Z\", \"hypothesis\": \"Multi-Round Iterative SC: N inverse scaling reveals disputed entities cause failures. Focused re-prompting on disputed entities (agreement < 0.6) with weighted aggregation (Round 2 weight=2) should reduce error rate on disputed entities without affecting non-disputed ones, closing part of the selection gap through iterative refinement rather than single-round aggregation.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-20T15:39:10.190Z\"}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python /root/autodl-tmp/struct_self_consist_ie/code/run_mrsc.py --base_model_path /root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-fewnerd-merged --data_path /root/autodl-tmp/struct_self_consist_ie/output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl --output_dir /root/autodl-tmp/struct_self_consist_ie/output/exp_mrsc_multi_round --batch_size 16\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl\", \"data_count\": 37648, \"model_name\": \"qwen25-7b-fewnerd-merged\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_mrsc_multi_round\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_mrsc_multi_round.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T17:12:53.641Z\"}, \"exp_lsc_latent_sc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:37:31.881Z\", \"updated_at\": \"2026-05-20T17:11:49.135Z\", \"hypothesis\": \"Latent Self-Consistency: F4 diagnostic proves LP is compressed (median range 0.041 nats). Hidden states contain richer per-sample information than scalar LP. Entity-level mean-pooled hidden state representations enable latent aggregation (centroid selection, latent confidence scoring, clustering) that bypasses LP compression and provides discriminative per-sample ranking unavailable from output-space signals.\", \"parent\": \"exp_e2_mixture_of_signals\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-20T15:39:11.609Z\"}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python run_lsc.py --base_model_path qwen25-7b-fewnerd-merged --data_path fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl --max_instances 2000\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_7b/qwen25_7b_n8_seed42/samples.jsonl\", \"data_count\": 2000, \"model_name\": \"qwen25-7b-fewnerd-merged\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-fewnerd-merged\", \"eval_data\": \"FewNERD test (gold-filtered, n=2000)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_lsc_latent_sc\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_lsc_latent_sc.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T16:51:53.120Z\", \"metrics\": {\"centroid_selection_f1\": 0.7593, \"lp_selection_f1\": 0.7845, \"latent_entity_conf_f1\": 0.8385, \"majority_vote_f1\": 0.8366, \"greedy_f1\": 0.7793, \"oracle_f1\": 0.8668, \"lp_vs_latent_rho\": 0.518, \"entity_match_rate\": 0.9945, \"n_instances\": 2000, \"runtime_s\": 507}}, \"exp_14b_inference_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T14:36:25.505Z\", \"updated_at\": \"2026-05-20T15:11:54.487Z\", \"hypothesis\": \"14B Qwen2.5 inference on SciERC (N∈{1,2,4,8,16}): correlation-selection gap pattern should be consistent at 14B scale with intermediate degeneracy rates between 7B and 32B.\", \"reproduce\": {\"finished_at\": \"2026-05-20T14:48:16.272Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-20T14:48:17.102Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T14:48:25.726567+00:00\"}]}}, \"exp_qwen25_14b_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-19T06:19:31.620Z\", \"updated_at\": \"2026-05-20T14:12:35.350Z\", \"hypothesis\": \"The correlation-selection gap pattern is consistent at 14B scale, filling the gap between 8B and 32B. Qwen2.5-14B QLoRA fine-tuned on FewNERD should show intermediate degeneracy rates and similar signal ranking patterns, providing a smooth scaling curve for the diagnostic findings.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:0,cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:0,cuda:1\", \"started_at\": \"2026-05-19T06:47:43.938Z\"}, \"notes\": \"2026-05-19 12:47 UTC: RECOVERED from false-positive startup recovery failure. Step 6483/41180 (15.7%), loss 0.0608, ~2.2s/it, ETA ~21h. checkpoint-6000 saved. screen train_14b_s42 PID 56766, GPU 0,1 95-96% util. Cron registered on PID 56773.\", \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"completed_at\": \"2026-05-19T12:44:29.453Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"2026-05-19 11:36 UTC: step 4934/41180 (12.0%), loss 0.067, ~2.15s/it, ETA ~22h. checkpoint-4000 saved. screen train_14b_s42, 2×5090 76-77% util.\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0,1 FORCE_TORCHRUN=1 NNODES=1 NPROC_PER_NODE=2 llamafactory-cli train train_config_qwen25_14b_fewnerd_s42.yaml\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/llmfactory_train.json\", \"data_count\": 131767, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"gpu_ids\": [\"cuda:0\", \"cuda:1\"], \"screen_session\": \"train_14b_s42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/train_14b_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-14b-fewnerd-qlora-s42/\"}, \"metrics\": {\"epoch\": 5, \"train_loss\": 0.0348, \"eval_loss\": 0.0323, \"train_runtime_hours\": 29.8, \"train_samples_per_second\": 6.141, \"train_steps_per_second\": 0.384, \"total_steps\": 41180}, \"conclusion\": \"success\"}, \"exp_b1_scd_conll_control\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:17:40.591Z\", \"updated_at\": \"2026-05-20T13:08:32.832Z\", \"hypothesis\": \"Negative control: SCD on CoNLL where construction gain is negative (-0.4pp, high degeneracy 70%). If SCD learns from construction pseudo-labels, it should NOT improve greedy F1 on a dataset where construction itself hurts. Expected: no improvement or slight degradation. Validates SCD mechanism.\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scd_conll_s42.yaml\", \"server\": \"autodl-5090-b\", \"gpu_ids\": [2], \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scd_conll_theta2n_s42.jsonl\", \"data_count\": 3453, \"model_name\": \"Qwen3-8B-FT-CoNLL\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll-scd-lora\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/scd_conll_s42.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-20T12:14:27.727Z\"}, \"failure_reason\": \"OVERRIDE: Training completed normally (690/690 steps, loss=0.0359). Cron misjudged as failed. Pending eval inference.\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-20T12:14:30.260Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-20T12:14:35.853775+00:00\"}]}, \"metrics\": {\"pre_scd_greedy_f1\": 0.9078, \"post_scd_greedy_f1\": 0.9184, \"delta_pp\": 1.06, \"training_steps\": 690, \"final_loss\": 0.0359, \"negative_control_confirmed\": false, \"note\": \"SURPRISE: SCD improved CoNLL F1 by +1.06pp despite negative construction gain. Possible explanations: (1) SCD provides general training benefit (more data), (2) additional training steps alone improve, (3) SCD mechanism doesn't require positive construction gain.\"}}, \"exp_qwen25_7b_fewnerd\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:41:43.121Z\", \"updated_at\": \"2026-05-20T05:45:54.613Z\", \"hypothesis\": \"Qwen2.5-7B QLoRA fine-tuned on FewNERD will produce structurally diverse samples enabling self-consistency-based entity extraction with meaningful LP-weighted consensus signals, comparable to the 14B model but with lower compute cost.\", \"spec\": {\"server\": \"autodl-5090-c\", \"gpu_ids\": [\"cuda:2\", \"cuda:3\"], \"command\": \"nohup bash run_fewnerd_qwen25_7b_pipeline.sh > logs/pipeline_qwen25_7b_fewnerd.log 2>&1 &\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/llmfactory_train.json\", \"data_count\": 131767, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-fewnerd-qlora-s42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/pipeline_qwen25_7b_fewnerd.log\", \"training_config\": \"train_config_qwen25_7b_fewnerd_s42.yaml\", \"export_config\": \"export_config_qwen25_7b_fewnerd.yaml\", \"pipeline_script\": \"run_fewnerd_qwen25_7b_pipeline.sh\", \"method\": \"QLoRA 4-bit nf4, rank=32, alpha=64, 5 epochs, lr=2e-4, effective_batch=32\", \"pipeline_phases\": \"train -> export/merge -> 3-seed N=8 inference (42/123/456) -> signal analysis -> entity construction\"}, \"notes\": \"2026-05-19 11:36 UTC: step 138/20590 (0.7%), ~2.34s/it, ETA ~13.3h. Pipeline PID 71837, llamafactory PID 71844. cuda:2,3 98-100% util. Cron registered on pipeline PID.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2,cuda:3\", \"metrics\": {\"3seed_mean\": {\"lp_rho\": 0.346, \"lp_rho_std\": 0.021, \"sj_rho\": 0.388, \"sj_rho_std\": 0.029, \"vc_rho\": 0.404, \"vc_rho_std\": 0.01, \"degen_pct\": 31.7, \"degen_std\": 0.9, \"greedy_f1\": 0.784, \"greedy_f1_std\": 0.001, \"oracle_f1\": 0.876, \"oracle_f1_std\": 0.003, \"construction_lp_delta_pp\": -0.11, \"construction_lp_delta_std\": 0.25}, \"per_seed\": {\"seed42\": {\"lp_rho\": 0.3221, \"sj_rho\": 0.3554, \"vc_rho\": 0.393, \"degen_pct\": 31.1, \"greedy_f1\": 0.7851, \"oracle_f1\": 0.8718, \"construction_lp_delta_pp\": -0.4, \"bootstrap_p\": 1, \"bootstrap_ci\": [-0.53, -0.26], \"cohens_d\": -0.0319}, \"seed123\": {\"lp_rho\": 0.3538, \"sj_rho\": 0.3979, \"vc_rho\": 0.4067, \"degen_pct\": 32.8, \"greedy_f1\": 0.785, \"oracle_f1\": 0.8777, \"construction_lp_delta_pp\": -0.03, \"bootstrap_p\": 0.651}, \"seed456\": {\"lp_rho\": 0.3629, \"sj_rho\": 0.4105, \"vc_rho\": 0.4118, \"degen_pct\": 31.3, \"greedy_f1\": 0.7825, \"oracle_f1\": 0.8771, \"construction_lp_delta_pp\": 0.09, \"bootstrap_p\": 0.168}}, \"construction_significant\": false}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T05:45:54.613Z\"}, \"exp_qwen25_72b_fewshot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T15:59:44.340Z\", \"updated_at\": \"2026-05-20T00:54:59.032Z\", \"hypothesis\": \"Few-shot prompting improves base NER F1 and LP signal quality, enabling LP-weighted construction to outperform greedy selection via dual-gating (sufficient LP ρ + low degeneracy).\", \"parent\": \"exp_qwen25_72b_zeroshot\", \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"started_at\": \"2026-05-19T16:22:20.071Z\", \"finished_at\": \"2026-05-20T00:47:36.445Z\", \"training_hours\": 8.42}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0,1,2,3 python code/fewshot_inference_72b.py --datasets scierc conll2003 fewnerd --output-dir output/72b_fewshot --seed 42\\\"\", \"server\": \"autodl-5090-b\", \"gpu\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"pid\": 131293, \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen25_72b_fewshot.log\", \"submitted_at\": \"2026-05-19T16:25:57.711Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/{scierc,conll2003,fewnerd}\", \"data_count\": 41652, \"model_name\": \"Qwen2.5-72B-Instruct-AWQ\", \"seed\": 42, \"gpu_ids\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"checkpoint_source\": \"Qwen2.5-72B-Instruct-AWQ (base model, no fine-tuning)\", \"eval_data\": \"SciERC + CoNLL-2003 + FewNERD test sets\", \"wall_clock_seconds\": 30541.3, \"gpu_hours\": 33.93}, \"metrics\": {\"scierc\": {\"lp_rho\": 0.06, \"sj_rho\": 0.293, \"fk_rho\": 0.301, \"vc_rho\": 0.258, \"em_rho\": 0.205, \"degen_pct\": 16.6, \"greedy_f1\": 0.461, \"oracle_f1\": 0.604, \"construction_f1\": 0.461, \"construction_delta_pp\": -0.08, \"bootstrap_p\": 0.544}, \"conll\": {\"lp_rho\": 0.106, \"sj_rho\": 0.442, \"fk_rho\": 0.451, \"vc_rho\": 0.426, \"em_rho\": 0.403, \"degen_pct\": 70, \"greedy_f1\": 0.745, \"oracle_f1\": 0.796, \"construction_f1\": 0.745, \"construction_delta_pp\": 0.03, \"bootstrap_p\": 0.417}, \"fewnerd\": {\"lp_rho\": 0.161, \"sj_rho\": 0.345, \"fk_rho\": 0.327, \"vc_rho\": 0.41, \"em_rho\": 0.302, \"degen_pct\": 45.2, \"greedy_f1\": 0.619, \"oracle_f1\": 0.702, \"construction_f1\": 0.619, \"construction_delta_pp\": 0.02, \"bootstrap_p\": 0.401}}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T00:47:43.131229+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"output/72b_fewshot/ + output/72b_fewshot_signals/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen25_72b_fewshot.log\", \"completed_at\": \"2026-05-20T00:54:59.032Z\"}, \"exp_qwen25_72b_zeroshot\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-19T06:19:28.597Z\", \"updated_at\": \"2026-05-19T16:23:10.481Z\", \"hypothesis\": \"A larger zero-shot model (72B) will show higher greedy F1 and wider oracle-greedy gap than fine-tuned smaller models, because increased capacity enables more diverse valid extractions per stochastic sample, making self-consistency signals (SJ, FK, VC, EM) more informative for quality estimation.\", \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"started_at\": \"2026-05-19T06:47:42.658Z\", \"finished_at\": \"2026-05-19T14:14:58.577Z\", \"training_hours\": 7.45}, \"notes\": \"2026-05-19 12:47 UTC: RECOVERED from false-positive startup recovery failure. 289848/301184 prompts (96.2%). SciERC ✅ (551) CoNLL ✅ (3453) FewNERD ~96%. ETA ~10-15min. PID 59040, 4×5090 100% util. Cron registered.\", \"failure_reason\": \"FALSE POSITIVE — cron误判。实验实际成功完成（3个数据集全部处理完毕）。\", \"completed_at\": \"2026-05-19T12:44:26.198Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"2026-05-19 11:36 UTC: 69.8% complete (210352/301184 prompts). SciERC ✅ CoNLL ✅ FewNERD ~66%. ETA ~1h15m. vLLM PID 59040, 4×5090 100% util.\"}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T14:15:08.634709+00:00\"}]}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0,1,2,3 python code/zeroshot_inference_72b.py --datasets scierc conll2003 fewnerd --output-dir output/72b_zeroshot --seed 42\", \"server\": \"autodl-5090-b\", \"data_path\": \"data/{scierc,conll2003,fewnerd}\", \"data_count\": 41630, \"model_name\": \"Qwen2.5-72B-Instruct-AWQ\", \"seed\": 42, \"gpu_ids\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"pid\": 59040}, \"conclusion\": \"negative\", \"metrics\": {\"scierc\": {\"greedy_f1\": 0.3993, \"lp_rho\": 0.081, \"vc_rho\": 0.277, \"sj_rho\": 0.217, \"degen_rate\": 0.21, \"construction_lp_weighted_f1\": 0.4146, \"construction_lp_delta_pp\": 1.53, \"construction_uniform_f1\": 0.3941, \"construction_uniform_delta_pp\": -0.52, \"lp_selection_f1\": 0.3984, \"majority_vote_f1\": 0.4132, \"oracle_f1\": 0.5489, \"bootstrap_p\": 0.0082, \"bootstrap_ci_lower\": 0.0025, \"bootstrap_ci_upper\": 0.0282, \"cohens_d\": 0.1027, \"n_instances\": 529, \"non_degen_delta_pp\": 1.65, \"non_degen_p\": 0.0069}, \"conll2003\": {\"greedy_f1\": 0.712, \"lp_rho\": -0.002, \"vc_rho\": 0.297, \"sj_rho\": 0.304, \"degen_rate\": 0.677, \"construction_lp_weighted_f1\": 0.7083, \"construction_lp_delta_pp\": -0.37, \"construction_uniform_f1\": 0.7028, \"construction_uniform_delta_pp\": -0.92, \"lp_selection_f1\": 0.708, \"majority_vote_f1\": 0.7034, \"oracle_f1\": 0.7651}, \"fewnerd\": {\"greedy_f1\": 0.6281, \"lp_rho\": 0.119, \"vc_rho\": 0.416, \"sj_rho\": 0.345, \"degen_rate\": 0.462, \"construction_lp_weighted_f1\": 0.6261, \"construction_lp_delta_pp\": -0.2, \"construction_uniform_f1\": 0.6112, \"construction_uniform_delta_pp\": -1.7, \"lp_selection_f1\": 0.6241, \"lp_selection_delta_pp\": -0.4, \"majority_vote_f1\": 0.6262, \"oracle_f1\": 0.7072}}}, \"exp_wnut17_qwen25_7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:19:33.960Z\", \"updated_at\": \"2026-05-19T11:49:07.313Z\", \"hypothesis\": \"The correlation-selection gap extends to noisy social media NER (WNUT-17). Unlike formal-domain datasets (SciERC/CoNLL/FewNERD), WNUT-17 has higher surface-level noise which may affect structural signal reliability differently. This tests domain generalization of the diagnostic framework.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2,cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2,cuda:3\", \"started_at\": \"2026-05-19T06:47:45.220Z\"}, \"spec\": {\"server\": \"autodl-5090-c\", \"gpu_ids\": [\"cuda:2\", \"cuda:3\"], \"command\": \"bash wait_and_train.sh (screen: exp_wnut17_7b)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/wnut17/llmfactory_train.json\", \"data_count\": 3404, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"training_config\": \"train_config_qwen25_7b_wnut17_s42.yaml\", \"method\": \"QLoRA 4-bit (bnb nf4), rank=32, alpha=64, all targets\", \"gpus\": \"cuda:2,3 (2x5090)\", \"epochs\": 5, \"effective_batch_size\": 32, \"pipeline\": \"train → export → 3-seed inference (N=8, T=1.0) → signal analysis → entity construction\", \"checkpoint_source\": \"self-trained on WNUT-17\", \"eval_data\": \"WNUT-17 test set\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-wnut17-qlora-s42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp_wnut17_7b_pipeline.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"seed42\": {\"greedy_f1\": 0.4524, \"construction_f1\": 0.4439, \"construction_delta_pp\": -0.84, \"construction_p\": 0.95}, \"seed123\": {\"greedy_f1\": 0.4518, \"construction_f1\": 0.4579, \"construction_delta_pp\": 0.61, \"construction_p\": 0.08}, \"seed456\": {\"greedy_f1\": 0.4526, \"construction_f1\": 0.4583, \"construction_delta_pp\": 0.57, \"construction_p\": 0.12}, \"oracle_headroom_pp\": \"6.3-9.2\"}, \"completed_at\": \"2026-05-19T11:22:56.623Z\"}, \"exp_llama_fewnerd_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:18:49.938Z\", \"updated_at\": \"2026-05-19T03:15:04.486Z\", \"hypothesis\": \"LLaMA-3.1-8B fine-tuned on FewNERD shows the same structured self-consistency phenomena (degeneracy, LP-F1 alignment, signal ranking) as Qwen models, providing cross-model generalization evidence. 3-seed inference (42/123/456) for statistical robustness.\", \"parent\": \"exp_llama_fewnerd_lora\", \"spec\": {\"command\": \"bash code/run_llama_fewnerd_inference.sh\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/\", \"data_count\": 37648, \"model_name\": \"LLaMA-3.1-8B-FewNERD-LoRA-merged\", \"seed\": \"42,123,456\", \"checkpoint_source\": \"exp_llama_fewnerd_lora\", \"eval_data\": \"FewNERD test set\", \"checkpoint_path\": \"checkpoints/llama3.1-8b-fewnerd-merged/\", \"log_path\": \"logs/llama_fewnerd_inference.log\"}, \"conclusion\": \"success\", \"metrics\": {\"3seed_mean\": {\"greedy_f1\": 0.7842, \"oracle_f1\": 0.8843, \"headroom_pp\": 10.01, \"degeneracy_pct\": 23.36, \"lp_delta_pp\": 0.36, \"dgs_delta_pp\": -0.35}, \"seed_42\": {\"greedy_f1\": 0.7841, \"oracle_f1\": 0.8854, \"degen\": 27.32}, \"seed_123\": {\"greedy_f1\": 0.784, \"oracle_f1\": 0.8839, \"degen\": 24.63}, \"seed_456\": {\"greedy_f1\": 0.7844, \"oracle_f1\": 0.8835, \"degen\": 18.13}, \"signal_ranking\": \"LP (+0.36pp) > SJ (-0.52) > FK (-0.53) > EM (-1.02) > VC (-2.39)\", \"lp_only_positive\": true, \"n_instances_gold_filtered\": 32565}, \"completed_at\": \"2026-05-19T03:15:04.486Z\"}, \"exp_entity_construction\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:00:12.074Z\", \"updated_at\": \"2026-05-19T02:40:17.571Z\", \"hypothesis\": \"Entity-level majority vote construction is the correct self-consistency analogy for structured IE: instead of selecting the best instance-level output, assemble a better output from entity-level consensus across N samples. Construction should outperform both greedy and best-of-N selection.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/entity_construction_fair.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/*/samples_*.json\", \"data_count\": 3, \"model_name\": \"analysis_cpu\", \"seed\": 42, \"checkpoint_path\": \"output/entity_construction_fair/\", \"log_path\": \"output/entity_construction_fair/\"}, \"completed_at\": \"2026-05-19T02:15:19.616Z\", \"metrics\": {\"n16_fair_cv\": {\"scierc_ner\": {\"cv_uniform_delta\": \"+1.35pp\", \"p_value\": 0.018, \"significant\": true}, \"conll_ner\": {\"cv_uniform_delta\": \"+0.10pp\", \"p_value\": 0.303, \"significant\": false}, \"fewnerd_ner\": {\"cv_uniform_delta\": \"+1.32pp\", \"p_value\": 0, \"significant\": true}, \"scierc_re\": {\"cv_uniform_delta\": \"+1.69pp\", \"p_value\": 0.049, \"significant\": true}}, \"n8_fair_cv\": {\"scierc_ner\": {\"uniform_confirm\": \"+1.54pp (p=0.023, sig)\", \"lp_weighted_confirm\": \"+1.67pp (p=0.004, sig)\", \"cv_uniform\": \"+1.12pp (p=0.057, borderline)\"}, \"conll_ner\": {\"cv_uniform\": \"-0.39pp (p=0.963, not sig)\"}, \"fewnerd_ner\": {\"lp_weighted_cv\": \"+0.88pp (p=0.000, sig)\", \"uniform_cv\": \"+0.32pp (p=0.003, sig)\"}}, \"adaptive_combination\": \"INVALIDATED - gold label leakage confirmed\", \"note\": \"5-fold CV, bootstrap B=10000, paired one-sided\"}}, \"exp_lp_alignment_gating\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:00:16.520Z\", \"updated_at\": \"2026-05-19T02:15:48.197Z\", \"hypothesis\": \"Within-instance LP-F1 alignment score (adjusted by valid_ratio for degeneracy) can automatically gate whether LP selection should be applied to a dataset. A small probe sample (50-100 instances) suffices for a stable gating decision.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/lp_alignment_gated_selection.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/*/samples_*.json\", \"data_count\": 3, \"model_name\": \"analysis_cpu\", \"seed\": 42, \"checkpoint_path\": \"output/prescriptive_analysis/\", \"log_path\": \"output/prescriptive_analysis/\"}, \"completed_at\": \"2026-05-19T02:15:23.716Z\", \"metrics\": {\"adjusted_score\": \"mean_rho * valid_ratio\", \"threshold\": 0.3, \"accuracy\": \"3/3 datasets correct\", \"robust_range\": \"0.2-0.4\"}}, \"exp_selective_prediction\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:00:13.989Z\", \"updated_at\": \"2026-05-19T02:15:46.588Z\", \"hypothesis\": \"QE signals (especially voting_confidence) can drive practical selective prediction: filtering out low-confidence instances yields significant F1 improvement on retained instances, enabling human-AI collaboration for structured IE.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/selective_prediction.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/*/samples_*.json\", \"data_count\": 3, \"model_name\": \"analysis_cpu\", \"seed\": 42, \"checkpoint_path\": \"output/prescriptive_analysis/\", \"log_path\": \"output/prescriptive_analysis/\"}, \"completed_at\": \"2026-05-19T02:15:21.704Z\", \"metrics\": {\"vc_best_signal\": true, \"f1_at_80pct_coverage\": {\"scierc\": \"+5.0pp\", \"conll\": \"+8.4pp\", \"fewnerd\": \"+6.2pp\"}, \"precision_coverage_curves\": \"output/prescriptive_analysis/fig_selective_prediction.pdf\"}}, \"exp_llama_fewnerd_lora\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T13:20:55.859Z\", \"updated_at\": \"2026-05-19T01:08:20.832Z\", \"hypothesis\": \"LLaMA-based model with LoRA fine-tuning on Few-NERD can provide a second model family (beyond Qwen) for cross-model generalization evidence of structured self-consistency phenomena in NER\", \"spec\": {\"command\": \"llamafactory-cli train train_config_llama_fewnerd.yaml\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": 137865, \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd\", \"data_count\": -1, \"model_name\": \"LLaMA-Few-NERD-LoRA\", \"seed\": 42, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/llama_fewnerd_train.log\", \"run_script\": \"run_llama_fewnerd_train_single_gpu.sh\", \"tmux_session\": \"llama_fewnerd\", \"note\": \"Retroactively registered - data_count unknown, seed assumed 42\"}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/llama3.1-8b-fewnerd-lora\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/llama_fewnerd_train.log\", \"conclusion\": \"success\", \"metrics\": {\"epoch\": 3, \"train_loss\": 0.0516, \"eval_loss\": 0.0323, \"train_runtime_hours\": 15.35, \"total_steps\": 24708, \"final_checkpoint\": \"checkpoint-24708\", \"adapter_size_mb\": 320}, \"completed_at\": \"2026-05-19T01:08:20.832Z\"}, \"hidden_state_probe_conll_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:57:45.711Z\", \"updated_at\": \"2026-05-19T00:30:18.272Z\", \"conclusion\": \"killed\", \"notes\": \"Not in D154 Dual Contribution framing\", \"completed_at\": \"2026-05-19T00:30:18.272Z\"}, \"hidden_state_probe_conll_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:35:05.317Z\", \"updated_at\": \"2026-05-19T00:30:16.471Z\", \"conclusion\": \"killed\", \"notes\": \"Not in D154 Dual Contribution framing\", \"completed_at\": \"2026-05-19T00:30:16.471Z\"}, \"exp_031_fewnerd_t12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:04:12.040Z\", \"updated_at\": \"2026-05-19T00:30:14.652Z\", \"hypothesis\": \"FewNERD T=1.2 temperature ablation: test if higher temperature reduces degeneracy on FewNERD as observed on SciERC\", \"conclusion\": \"killed\", \"failure_reason\": \"数据不可用于论文：测试集(37648 vs T=1.0的5000)、N(8 vs 16)、分析管道(MVP pilot vs 5-signal)三重不一致。Director决定不重跑(DDL约束+非核心claim)。\", \"notes\": \"T=1.2 ablation not in paper scope, SciERC T=1.2 sufficient\", \"completed_at\": \"2026-05-19T00:30:14.652Z\"}, \"exp_030_conll_t12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:24:47.839Z\", \"updated_at\": \"2026-05-19T00:30:12.698Z\", \"hypothesis\": \"CoNLL T=1.2 temperature ablation: test if higher temperature reduces degeneracy on CoNLL as observed on SciERC\", \"conclusion\": \"killed\", \"failure_reason\": \"数据不可用于论文：N不一致(N=8 vs T=1.0基准的N=16)。Director决定不重跑——SciERC T消融(T=0.5/0.8/1.0/1.2, 551inst, N=8)已够用，论文温度消融用SciERC单数据集。\", \"notes\": \"T=1.2 ablation not in paper scope, SciERC T=1.2 sufficient\", \"completed_at\": \"2026-05-19T00:30:12.699Z\"}, \"mbr_pilot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:56:06.462Z\", \"updated_at\": \"2026-05-19T00:29:39.285Z\", \"conclusion\": \"killed\", \"notes\": \"MBR tested negative as one of 6 methods, stale entry\", \"completed_at\": \"2026-05-19T00:29:39.285Z\"}, \"dgs_pilot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:56:04.572Z\", \"updated_at\": \"2026-05-19T00:29:37.275Z\", \"hypothesis\": \"Degeneracy-Gated Selection (DGS) validates Two-Condition Theory: using degeneracy rate as gating mechanism to switch between greedy (degenerate) and LP selection (non-degenerate), the improvement direction should follow a monotonic gradient — low degeneracy yields positive delta, high degeneracy yields negative delta.\", \"conclusion\": \"killed\", \"notes\": \"D154: DGS demoted to explored heuristic, cross-model direction contradiction (D152)\", \"completed_at\": \"2026-05-19T00:29:37.275Z\"}, \"exp_fewnerd_s789_n8\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:17:34.011Z\", \"updated_at\": \"2026-05-18T23:18:28.125Z\", \"hypothesis\": \"FewNERD seed789 (4th seed) for statistical CI strengthening: 4-seed protocol provides tighter confidence intervals on LP selection gain and DGS effectiveness in low-degeneracy regime.\", \"parent\": \"exp_029a\", \"spec\": {\"command\": \"python code/analyze_fewnerd_s789.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/samples.jsonl\", \"data_count\": 37648, \"model_name\": \"Qwen3-8B (ft_002_v2)\", \"seed\": 789, \"checkpoint_source\": \"exp_021 shards\", \"eval_data\": \"FewNERD test (37648 instances, 32565 gold-filtered)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T23:18:17.902Z\", \"metrics\": {\"greedy_f1\": 0.7478, \"oracle_f1\": 0.8714, \"headroom_pp\": 12.37, \"degen_rate\": 0.1177, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 37648, \"n_valid\": 32565, \"lp_sel_f1\": 0.7614, \"lp_delta_pp\": 1.36, \"lp_rho_global\": 0.1788, \"lp_rho_cond\": 0.176, \"dgs_f1\": 0.7621, \"dgs_delta_pp\": 1.43, \"dgs_vs_lp_pp\": 0.07, \"best_signal\": \"LP\", \"four_seed_mean_greedy\": 0.7481, \"four_seed_mean_lp_delta_pp\": 1.38, \"four_seed_lp_delta_ci95\": [1.32, 1.44]}}, \"exp_026_t12_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:43.694Z\", \"updated_at\": \"2026-05-18T22:07:24.547Z\", \"hypothesis\": \"Temperature ablation (T=1.2, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 1.2\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:05.941Z\", \"metrics\": {\"ner_greedy_f1\": 0.6637, \"ner_oracle_f1\": 0.7821, \"rho_sj_ner\": 0.3995, \"sample_f1_pct_zero\": 14.08, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t12_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:42.754Z\", \"updated_at\": \"2026-05-18T22:07:23.135Z\", \"hypothesis\": \"Temperature ablation (T=1.2, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 1.2\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:04.119Z\", \"metrics\": {\"ner_greedy_f1\": 0.6595, \"ner_oracle_f1\": 0.7895, \"rho_sj_ner\": 0.359, \"sample_f1_pct_zero\": 13.99, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t10_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:41.840Z\", \"updated_at\": \"2026-05-18T22:07:21.767Z\", \"hypothesis\": \"Temperature ablation (T=1.0, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:02.272Z\", \"metrics\": {\"ner_greedy_f1\": 0.6621, \"ner_oracle_f1\": 0.7754, \"rho_sj_ner\": 0.3921, \"sample_f1_pct_zero\": 12.97, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t10_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:40.599Z\", \"updated_at\": \"2026-05-18T22:07:20.459Z\", \"hypothesis\": \"Temperature ablation (T=1.0, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:00.430Z\", \"metrics\": {\"ner_greedy_f1\": 0.6633, \"ner_oracle_f1\": 0.7777, \"rho_sj_ner\": 0.3809, \"sample_f1_pct_zero\": 12.59, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t10_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:39.473Z\", \"updated_at\": \"2026-05-18T22:07:19.035Z\", \"hypothesis\": \"Temperature ablation (T=1.0, seed=42) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 42 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed42.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:58.573Z\", \"metrics\": {\"ner_greedy_f1\": 0.6617, \"ner_oracle_f1\": 0.7798, \"rho_sj_ner\": 0.3598, \"sample_f1_pct_zero\": 12.9, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t08_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:38.605Z\", \"updated_at\": \"2026-05-18T22:07:17.604Z\", \"hypothesis\": \"Temperature ablation (T=0.8, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 0.8\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:56.681Z\", \"metrics\": {\"ner_greedy_f1\": 0.6641, \"ner_oracle_f1\": 0.7694, \"rho_sj_ner\": 0.3771, \"sample_f1_pct_zero\": 11.79, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t08_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:37.454Z\", \"updated_at\": \"2026-05-18T22:07:16.089Z\", \"hypothesis\": \"Temperature ablation (T=0.8, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 0.8\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:54.734Z\", \"metrics\": {\"ner_greedy_f1\": 0.6607, \"ner_oracle_f1\": 0.7714, \"rho_sj_ner\": 0.3893, \"sample_f1_pct_zero\": 11.22, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t05_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:36.536Z\", \"updated_at\": \"2026-05-18T22:07:14.675Z\", \"hypothesis\": \"Temperature ablation (T=0.5, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 0.5\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:52.749Z\", \"metrics\": {\"ner_greedy_f1\": 0.6639, \"ner_oracle_f1\": 0.7437, \"rho_sj_ner\": 0.3279, \"sample_f1_pct_zero\": 10.28, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t05_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:35.201Z\", \"updated_at\": \"2026-05-18T22:07:13.198Z\", \"hypothesis\": \"Temperature ablation (T=0.5, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 0.5\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:50.703Z\", \"metrics\": {\"ner_greedy_f1\": 0.6611, \"ner_oracle_f1\": 0.7444, \"rho_sj_ner\": 0.3133, \"sample_f1_pct_zero\": 10.09, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_029b\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T23:32:18.543Z\", \"updated_at\": \"2026-05-18T22:05:45.856Z\", \"hypothesis\": \"Training convergence modulates degeneracy across datasets. SciERC 10-epoch training should produce higher degeneracy than 5-epoch baseline (17.8%), confirming monotonic epoch-degeneracy relationship across datasets.\", \"parent\": \"ft_002_v2\", \"failure_reason\": \"OOM on cuda:1 due to residual vLLM process (PID 416808) occupying 30.2GB VRAM\", \"reproduce\": {\"finished_at\": \"2026-05-18T02:05:15.948Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T00:55:29.806594+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T01:58:43.646574+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T02:05:20.480884+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"completed_at\": \"2026-05-18T00:56:47.625Z\", \"spec\": {\"pid\": \"441471\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"command\": \"FORCE_TORCHRUN=0 CUDA_VISIBLE_DEVICES=1 llamafactory-cli train train_config_scierc_10ep.yaml\", \"data_path\": \"scierc_uie_train\", \"data_count\": 1861, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen3-8B\", \"eval_data\": \"scierc_uie_test\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-10epoch-lora/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_029b.log\"}, \"metrics\": {\"degen_rate\": 0.478, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"conclusion\": \"success\"}, \"exp_029a\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T23:32:17.191Z\", \"updated_at\": \"2026-05-18T22:05:44.959Z\", \"hypothesis\": \"Training convergence modulates degeneracy across datasets. SciERC 3-epoch training should produce lower degeneracy than 5-epoch baseline (17.8%), confirming epoch confound is not Few-NERD-specific.\", \"parent\": \"ft_002_v2\", \"spec\": {\"command\": \"FORCE_TORCHRUN=0 CUDA_VISIBLE_DEVICES=0 bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_scierc_3ep.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 436761, \"data_path\": \"data/scierc_uie_train\", \"data_count\": 1861, \"model_name\": \"Qwen3-8B LoRA rank=32\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-3epoch-lora\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp_029a_inference.log\", \"checkpoint_source\": \"Qwen/Qwen3-8B\", \"eval_data\": \"data/scierc_uie_dev\"}, \"reproduce\": {\"finished_at\": \"2026-05-18T00:55:16.392Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T00:55:20.617085+00:00\"}]}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T01:00:18.242Z\", \"metrics\": {\"degen_rate\": 0.064, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_021_fewnerd_n8_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:17.992Z\", \"updated_at\": \"2026-05-18T22:04:50.774Z\", \"hypothesis\": \"Multi-seed replication (seed=456) of Qwen3-8B FewNERD N=8 SCS inference to validate structural consistency signal on fine-grained NER dataset.\", \"spec\": {\"command\": \"python scs_inference.py --dataset fewnerd --seed 456 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd\", \"data_count\": 37648, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed456_run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:35.573Z\", \"metrics\": {\"degen_rate\": 0.1212, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 37648, \"n_valid\": 32565, \"n_gold_empty\": 5083, \"ner_greedy_f1\": 0.7888, \"ner_oracle_f1\": 0.881, \"rho_fk_ner\": 0.1632, \"rho_sj_ner\": 0.313, \"sample_f1_pct_zero\": 19.32}}, \"exp_021_fewnerd_n8_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:16.735Z\", \"updated_at\": \"2026-05-18T22:04:49.470Z\", \"hypothesis\": \"Multi-seed replication (seed=123) of Qwen3-8B FewNERD N=8 SCS inference to validate structural consistency signal on fine-grained NER dataset.\", \"spec\": {\"command\": \"python scs_inference.py --dataset fewnerd --seed 123 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd\", \"data_count\": 37648, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed123_run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:33.731Z\", \"metrics\": {\"degen_rate\": 0.1312, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 37648, \"n_valid\": 32565, \"n_gold_empty\": 5083, \"ner_greedy_f1\": 0.7885, \"ner_oracle_f1\": 0.8892, \"rho_fk_ner\": 0.1602, \"rho_sj_ner\": 0.3083, \"sample_f1_pct_zero\": 20.39}}, \"exp_002_conll_n16_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:15.720Z\", \"updated_at\": \"2026-05-18T22:04:46.954Z\", \"hypothesis\": \"Multi-seed replication (seed=456) of Qwen3-8B CoNLL-2003 N=16 SCS inference to validate structural consistency signal stability across random seeds.\", \"spec\": {\"command\": \"python scs_inference.py --dataset conll2003 --seed 456 --n_samples 16 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:31.934Z\", \"metrics\": {\"degen_rate\": 0.5544, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"ner_greedy_f1\": 0.9074, \"ner_oracle_f1\": 0.9549, \"rho_fk_ner\": 0.4718, \"rho_sj_ner\": 0.4819, \"sample_f1_pct_zero\": 7.02}}, \"exp_002_conll_n16_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:14.343Z\", \"updated_at\": \"2026-05-18T22:04:45.039Z\", \"hypothesis\": \"Multi-seed replication (seed=123) of Qwen3-8B CoNLL-2003 N=16 SCS inference to validate structural consistency signal stability across random seeds.\", \"spec\": {\"command\": \"python scs_inference.py --dataset conll2003 --seed 123 --n_samples 16 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:29.992Z\", \"metrics\": {\"degen_rate\": 0.471, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"ner_greedy_f1\": 0.9068, \"ner_oracle_f1\": 0.9633, \"rho_fk_ner\": 0.4524, \"rho_sj_ner\": 0.4621, \"sample_f1_pct_zero\": 7.54}}, \"exp_017_llama_conll_n16_s456_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:04.572Z\", \"updated_at\": \"2026-05-18T20:50:15.047Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed456.\", \"parent\": \"exp_017_llama_conll_n16_s456\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 456, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_s456_r1024\", \"gpu\": \"cuda:2\", \"pid\": \"175870\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"tmux_session\": \"exp_017_llama_conll_n16_s456_r1024\"}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.8672, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"parse_rate\": 1, \"ner_greedy_f1\": 0.9265, \"ner_oracle_f1\": 0.9499, \"rho_fk_ner\": 0.469, \"rho_sj_ner\": 0.4734, \"rho_vc_ner\": 0.4722, \"rho_em_ner\": 0.4752, \"rho_lp_ner\": 0.3099, \"auroc_fk_ner\": 0.7408, \"auroc_sj_ner\": 0.7428, \"auroc_vc_ner\": 0.7495, \"auroc_em_ner\": 0.7444, \"auroc_lp_ner\": 0.7628, \"auroc_note\": \"median F1=1.0, AUROC uses >=median threshold\", \"rho_note\": \"CORRECTED 2026-05-15: old values (rho_fk=0.8085,rho_sj=0.1895) were inflated/deflated by 697 gold-empty instances. Now uses gold-filtered pipeline (n=2756).\"}, \"checkpoint_path\": \"N/A (inference-only)\", \"log_path\": \"output/exp_017_llama_conll_n16_s456_r1024_run.log\", \"completed_at\": \"2026-05-15T11:45:25.899Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=456 (max_tokens=1024 rerun): cross-model multi-seed validation. Confirms structural>surface ordering is stable across seeds for LLaMA on CoNLL after gold-filtering correction.\"}, \"exp_017_llama_conll_n16_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:01.036Z\", \"updated_at\": \"2026-05-18T20:50:11.906Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed42.\", \"parent\": \"exp_017_llama_conll_n16\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_r1024\", \"gpu\": \"cuda:1\", \"pid\": \"175734\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"tmux_session\": \"exp_017_llama_conll_n16_r1024\"}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.8647, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"parse_rate\": 1, \"ner_greedy_f1\": 0.9265, \"ner_oracle_f1\": 0.9499, \"rho_fk_ner\": 0.4752, \"rho_sj_ner\": 0.4836, \"rho_vc_ner\": 0.4746, \"rho_em_ner\": 0.4818, \"rho_lp_ner\": 0.3136, \"auroc_fk_ner\": 0.7467, \"auroc_sj_ner\": 0.7496, \"auroc_vc_ner\": 0.7529, \"auroc_em_ner\": 0.7508, \"auroc_lp_ner\": 0.7661, \"auroc_note\": \"median F1=1.0, AUROC uses >=median threshold\", \"rho_note\": \"CORRECTED 2026-05-15: old values (rho_fk=0.8095,rho_sj=0.1815) were inflated/deflated by 697 gold-empty instances. Now uses gold-filtered pipeline (n=2756).\"}, \"checkpoint_path\": \"N/A (inference-only)\", \"log_path\": \"output/exp_017_llama_conll_n16_r1024_run.log\", \"completed_at\": \"2026-05-15T11:45:23.213Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=42 (max_tokens=1024 rerun): cross-model baseline on CoNLL. Establishes LLaMA signal rankings after gold-filtering correction (fixes inflated FK ρ from gold-empty instances).\"}, \"exp_018_llama_scierc_seed456_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:12:43.492Z\", \"updated_at\": \"2026-05-18T20:50:04.988Z\", \"spec\": {\"hypothesis\": \"D066 fresh rerun: LLaMA SciERC seed=456 with explicit max_tokens=1024. Replaces exp_007 re-analysis for clean 3-seed comparison.\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed456_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": \"157584\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"finished_at\": \"2026-05-15T06:18:22.307Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T06:18:24.880896+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_018_llama_scierc_seed456_r1024\", \"metrics\": {\"degen_rate\": 0.2741, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"ner_greedy_f1\": 0.6597, \"ner_oracle_f1\": 0.7683, \"ner_oracle_headroom\": 0.1086, \"ner_cond_rho_fk\": 0.1472, \"ner_cond_rho_sj\": 0.2718, \"ner_cond_rho_logprob\": 0.083, \"ner_logprob_auroc_cond\": 0.5485, \"re_greedy_f1\": 0.4338, \"re_oracle_f1\": 0.5834, \"re_oracle_headroom\": 0.1496, \"re_cond_rho_fk\": 0.2107, \"re_cond_rho_sj\": 0.3898, \"re_cond_rho_logprob\": 0.1252, \"re_logprob_auroc_cond\": 0.6119, \"ner_structural_beats_logprob\": true, \"re_structural_beats_logprob\": true}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:21:45.350Z\", \"hypothesis\": \"LLaMA SciERC seed=456 (max_tokens=1024): multi-seed cross-model validation. Complements seed42 for LLaMA 3-seed protocol on SciERC NER+RE signal rankings.\"}, \"exp_018_llama_scierc_seed42_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:09:57.155Z\", \"updated_at\": \"2026-05-18T20:50:00.335Z\", \"spec\": {\"hypothesis\": \"D066 fresh rerun: LLaMA SciERC seed=42 with explicit max_tokens=1024. Replaces exp_007_llama_inference for clean 3-seed comparison.\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed42_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 42, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed42_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed42_r1024.log\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"156809\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed42_r1024.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed42_r1024\\\"\", \"finished_at\": \"2026-05-15T06:15:47.963Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T06:15:50.613872+00:00\"}]}, \"metrics\": {\"degen_rate\": 0.2495, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"ner\": {\"full\": {\"SJ\": {\"rho\": 0.3096, \"tau\": 0.2288, \"auroc\": 0.6683}, \"FK\": {\"rho\": 0.2352, \"tau\": 0.1759, \"auroc\": 0.6069}, \"logprob\": {\"rho\": 0.1503, \"tau\": 0.1087, \"auroc\": 0.5318}, \"EM\": {\"rho\": 0.2587, \"tau\": 0.1966, \"auroc\": 0.7174}, \"voting_conf\": {\"rho\": 0.4053, \"tau\": 0.3042, \"auroc\": 0.6967}}, \"conditional\": {\"SJ\": {\"rho\": 0.2718, \"tau\": null, \"auroc\": 0.6565}, \"FK\": {\"rho\": 0.1472, \"tau\": null, \"auroc\": 0.5866}, \"logprob\": {\"rho\": 0.081, \"tau\": null, \"auroc\": 0.5129}, \"EM\": {\"rho\": 0.3165, \"tau\": null, \"auroc\": 0.7244}, \"voting_conf\": {\"rho\": 0.3078, \"tau\": null, \"auroc\": 0.6714}}, \"greedy_f1\": 0.6607, \"oracle_f1\": 0.7781, \"n_full\": 529, \"n_cond\": 478}, \"re\": {\"full\": {\"SJ\": {\"rho\": 0.2748, \"tau\": 0.2102, \"auroc\": 0.7244}, \"FK\": {\"rho\": 0.3027, \"tau\": 0.2337, \"auroc\": 0.691}, \"logprob\": {\"rho\": 0.3163, \"tau\": 0.233, \"auroc\": 0.6313}, \"EM\": {\"rho\": 0.1681, \"tau\": 0.1275, \"auroc\": 0.7697}, \"voting_conf\": {\"rho\": 0.384, \"tau\": 0.2965, \"auroc\": 0.7337}}, \"conditional\": {\"SJ\": {\"rho\": 0.3461, \"tau\": null, \"auroc\": 0.7233}, \"FK\": {\"rho\": 0.1969, \"tau\": null, \"auroc\": 0.6684}, \"logprob\": {\"rho\": 0.0888, \"tau\": null, \"auroc\": 0.5556}, \"EM\": {\"rho\": 0.4969, \"tau\": null, \"auroc\": 0.819}, \"voting_conf\": {\"rho\": 0.3433, \"tau\": null, \"auroc\": 0.7003}}, \"greedy_f1\": 0.4319, \"oracle_f1\": 0.5775, \"n_full\": 397, \"n_cond\": 251}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:21:47.660Z\", \"hypothesis\": \"LLaMA SciERC seed=42 (max_tokens=1024): cross-model validation on SciERC. Establishes LLaMA NER signal rankings on same dataset as Qwen for direct model-family comparison.\"}, \"exp_002_conll_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:12:16.041Z\", \"updated_at\": \"2026-05-18T20:49:50.398Z\", \"spec\": {\"hypothesis\": \"Qwen CoNLL-2003 N=16: cross-dataset N-scaling comparison with SciERC N=16\", \"plan_id\": \"exp-002\", \"parent\": \"exp_002_ner_conll2003\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_002_conll_n16\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.4844, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"N\": 16, \"dataset\": \"conll2003\", \"subtask\": \"ner\", \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2614, \"greedy_f1\": 0.907, \"full\": {\"SJ_rho\": 0.4496, \"FK_rho\": 0.3928, \"logprob_rho\": 0.3146, \"EM_rho\": 0.4627, \"voting_conf_rho\": 0.4286, \"SJ_AUROC\": 0.8264, \"FK_AUROC\": 0.7821, \"logprob_AUROC\": 0.7531, \"EM_AUROC\": 0.8409, \"voting_conf_AUROC\": 0.8071, \"SJ_ECE\": 0.0747, \"FK_ECE\": 0.1786, \"logprob_ECE\": 0.2031, \"EM_ECE\": 0.0786, \"voting_conf_ECE\": 0.529}, \"conditional\": {\"SJ_rho\": 0.4208, \"FK_rho\": 0.3494, \"logprob_rho\": 0.3756, \"EM_rho\": 0.4658, \"voting_conf_rho\": 0.3654, \"SJ_AUROC\": 0.8405, \"FK_AUROC\": 0.7819, \"logprob_AUROC\": 0.8259, \"EM_AUROC\": 0.8781, \"voting_conf_AUROC\": 0.7951, \"SJ_ECE\": 0.0982, \"FK_ECE\": 0.1899, \"logprob_ECE\": 0.2504, \"EM_ECE\": 0.0997, \"voting_conf_ECE\": 0.6096}, \"n8_vs_n16_delta_rho_full\": {\"SJ\": 0.0139, \"FK\": -0.007, \"logprob\": -0.0011, \"EM\": 0.012, \"voting_conf\": 0.0049}}, \"checkpoint_path\": \"output/exp_002_conll_n16/samples.jsonl\", \"log_path\": \"output/exp_002_conll_n16.log\", \"completed_at\": \"2026-05-14T18:58:40.473Z\", \"hypothesis\": \"CoNLL N=16 NER: cross-dataset validation on high-performance NER dataset. Tests if structural signals retain advantage when base model performance is already high (greedy F1 > 0.9).\"}, \"exp_012_rerun_1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:11:33.777Z\", \"updated_at\": \"2026-05-18T20:49:42.395Z\", \"spec\": {\"hypothesis\": \"Verify if max_tokens=512 truncation inflated Table 1 N=8 SciERC signal values. Rerun with max_tokens=1024 for clean comparison.\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"parent\": \"exp_012_logprob_baseline\", \"data_count\": 551, \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_012_rerun_1024\", \"checkpoint_path\": \"output/exp_012_rerun_1024/\", \"log_path\": \"output/exp_012_rerun_1024/run.log\", \"data_path\": \"data/scierc/processed_data\"}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.1777, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"ner_full\": {\"n\": 529, \"SJ\": {\"rho\": 0.3599, \"tau\": 0.2646, \"AUROC\": 0.6917, \"ECE\": 0.4531, \"rho_ci95\": [0.2732, 0.4389], \"AUROC_ci95\": [0.6304, 0.7406]}, \"FK\": {\"rho\": 0.2665, \"tau\": 0.1974, \"AUROC\": 0.629, \"ECE\": 0.4512, \"rho_ci95\": [0.1743, 0.3486], \"AUROC_ci95\": [0.5612, 0.6882]}, \"logprob\": {\"rho\": 0.2052, \"tau\": 0.1478, \"AUROC\": 0.5783, \"ECE\": 0.7064, \"rho_ci95\": [0.1171, 0.2904], \"AUROC_ci95\": [0.5179, 0.6387]}, \"EM\": {\"rho\": 0.2945, \"tau\": 0.2208, \"AUROC\": 0.7493, \"ECE\": 0.3526, \"rho_ci95\": [0.2094, 0.37], \"AUROC_ci95\": [0.7002, 0.7928]}, \"voting_conf\": {\"rho\": 0.3792, \"tau\": 0.2805, \"AUROC\": 0.6841, \"ECE\": 0.3807, \"rho_ci95\": [0.2972, 0.4486], \"AUROC_ci95\": [0.6249, 0.7366]}}, \"ner_cond\": {\"n\": 477, \"SJ\": {\"rho\": 0.3113, \"tau\": 0.2257, \"AUROC\": 0.6772, \"ECE\": 0.4416, \"rho_ci95\": [0.2353, 0.3959], \"AUROC_ci95\": [0.621, 0.7337]}, \"FK\": {\"rho\": 0.1761, \"tau\": 0.1284, \"AUROC\": 0.6078, \"ECE\": 0.4389, \"rho_ci95\": [0.0839, 0.2665], \"AUROC_ci95\": [0.5442, 0.6709]}, \"logprob\": {\"rho\": 0.1538, \"tau\": 0.1111, \"AUROC\": 0.5633, \"ECE\": 0.6803, \"rho_ci95\": [0.0637, 0.2424], \"AUROC_ci95\": [0.5032, 0.6232]}, \"EM\": {\"rho\": 0.3596, \"tau\": 0.2735, \"AUROC\": 0.7556, \"ECE\": 0.3257, \"rho_ci95\": [0.2819, 0.4408], \"AUROC_ci95\": [0.7011, 0.8107]}, \"voting_conf\": {\"rho\": 0.3, \"tau\": 0.2189, \"AUROC\": 0.6618, \"ECE\": 0.3746, \"rho_ci95\": [0.2168, 0.3836], \"AUROC_ci95\": [0.6004, 0.7201]}}, \"re_full\": {\"n\": 397, \"SJ\": {\"rho\": 0.2503, \"tau\": 0.1878, \"AUROC\": 0.6702, \"ECE\": 0.3865}, \"FK\": {\"rho\": 0.2752, \"tau\": 0.2117, \"AUROC\": 0.6089, \"ECE\": 0.4405}, \"logprob\": {\"rho\": 0.2662, \"tau\": 0.1951, \"AUROC\": 0.6005, \"ECE\": 0.7694}, \"EM\": {\"rho\": 0.1344, \"tau\": 0.1081, \"AUROC\": 0.7059, \"ECE\": 0.3548}, \"voting_conf\": {\"rho\": 0.3498, \"tau\": 0.2663, \"AUROC\": 0.6935, \"ECE\": 0.2724}}, \"re_cond\": {\"n\": 238, \"SJ\": {\"rho\": 0.2457, \"tau\": 0.1811, \"AUROC\": 0.6463, \"ECE\": 0.2941}, \"FK\": {\"rho\": 0.1139, \"tau\": 0.0876, \"AUROC\": 0.551, \"ECE\": 0.3424}, \"logprob\": {\"rho\": 0.0112, \"tau\": 0.0051, \"AUROC\": 0.5186, \"ECE\": 0.6464}, \"EM\": {\"rho\": 0.4165, \"tau\": 0.3256, \"AUROC\": 0.7515, \"ECE\": 0.2232}, \"voting_conf\": {\"rho\": 0.2409, \"tau\": 0.178, \"AUROC\": 0.642, \"ECE\": 0.207}}, \"delta_vs_512_ner_full_rho\": {\"SJ\": 0.0034, \"FK\": 0.0014, \"EM\": 0.0379, \"voting_conf\": -0.1226, \"logprob\": 0.0656}, \"provenance_note\": \"exp_015_v2 scierc_n8_logprob used exp_012_logprob (max_tokens=512 truncated data). voting_conf was inflated 0.502→0.379, logprob was suppressed 0.140→0.205.\"}, \"completed_at\": \"2026-05-14T23:10:33.075Z\", \"hypothesis\": \"Canonical SciERC baseline with max_tokens=1024: Qwen3-8B ft_002_v2, N=8, T=1.0, seed=42, joint NER+RE. Establishes ground-truth ρ rankings and selection F1 for all 5 signals under correct generation length.\"}, \"exp_llama_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:15:27.504Z\", \"updated_at\": \"2026-05-18T20:49:10.758Z\", \"hypothesis\": \"LLaMA-3.1-8B on SciERC with seed=456 will show consistent 5-signal ranking patterns (SJ/FK > logprob) and DGS selection gains comparable to seed=42 and seed=123, confirming cross-seed stability.\", \"spec\": {\"command\": \"python3 code/analyze_llama_scierc_seed456_5signal.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_018_llama_scierc_seed456/samples.jsonl\", \"data_count\": 551, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"same as seed123\", \"eval_data\": \"SciERC test (551 instances)\", \"checkpoint_path\": \"output/exp_018_llama_scierc_seed456/5signal_dgs_report.json\", \"log_path\": \"output/exp_018_llama_scierc_seed456/run.log\"}, \"metrics\": {\"greedy_f1\": 0.6457, \"oracle_f1\": 0.7574, \"headroom\": 0.1117, \"dgs_f1\": 0.6454, \"degen_rate\": 0.2741, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"rho_SJ_full\": 0.3663, \"rho_FK_full\": 0.3115, \"rho_logprob_full\": 0.1911, \"rho_EM_full\": 0.3088, \"rho_vc_full\": 0.4135, \"auroc_SJ_full\": 0.7061, \"auroc_EM_full\": 0.7538, \"n_valid\": 529, \"n_conditional\": 478}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T19:16:00.973Z\"}, \"exp_007_llama_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:10:26.278Z\", \"updated_at\": \"2026-05-18T20:49:08.934Z\", \"name\": \"LLaMA-3.1-8B SciERC NER inference seed=123\", \"hypothesis\": \"Structural consistency signals (SJ, FK) correlate with entity F1 for LLaMA-8B on SciERC at seed=123, and DGS selection improves over greedy baseline\", \"spec\": {\"command\": \"python3 code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed123\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"LLaMA-3.1-8B-Instruct (SciERC LoRA fine-tuned)\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/llama3.1-8b-scierc-merged\", \"checkpoint_path\": \"checkpoints/llama3.1-8b-scierc-lora\", \"log_path\": \"output/exp_018_llama_scierc_seed123/report.json\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T19:11:30.781Z\", \"metrics\": {\"greedy_f1\": 0.6454, \"oracle_f1\": 0.7657, \"headroom\": 0.1204, \"degen_rate\": 0.2665, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"dgs_delta_pp\": -0.38, \"rho_SJ_full\": 0.3552, \"rho_voting_conf_full\": 0.4193, \"auroc_SJ_full\": 0.7092, \"auroc_EM_full\": 0.7468}}, \"exp_qwen3_4b_conll_scs_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:08:28.512Z\", \"updated_at\": \"2026-05-18T20:49:06.922Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_conll_scs_inference\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"222184\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_qwen3_4b_conll_scs_inference/report.json\", \"submitted_at\": \"2026-05-15T19:10:19.757Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-merged\", \"wall_clock_seconds\": 523.8, \"gpu_hours\": 0.15}, \"metrics\": {\"greedy_f1\": 0.9251, \"oracle_f1\": 0.9408, \"oracle_headroom_pp\": 1.57, \"SJ_rho_full\": 0.4045, \"SJ_rho_cond\": 0.4306, \"FK_rho_full\": 0.3961, \"FK_rho_cond\": 0.42, \"LP_rho_full\": 0.3186, \"LP_rho_cond\": 0.3378, \"LP_auroc_full\": 0.7689, \"LP_auroc_cond\": 0.8153, \"fleiss_kappa_mean\": 0.9349, \"soft_jaccard_mean\": 0.9754, \"structural_beats_surface\": true, \"rho_advantage_pp\": 0.84, \"n_instances\": 3453, \"n_gold_empty_filtered\": 697, \"n_greedy_f1_zero_filtered\": 112, \"verdict\": \"MARGINAL\", \"degen_rate\": 0.9057, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:19:03.585Z\", \"notes\": \"4B CoNLL SCS inference completed. SJ>FK>LP ordering preserved at 4B scale (rho 0.405>0.396>0.319). Greedy F1=0.925 outperforms 8B (0.907), but SJ rho is lower (0.405 vs 0.450 at 8B N=16). Structural beats surface confirmed (+0.84pp). Verdict MARGINAL due to small oracle headroom (1.57pp) — the model is already very good at CoNLL, leaving little room for selection improvement.\", \"hypothesis\": \"CoNLL 4B SCS inference (checkpoint-3800): cross-scale evidence for correlation-selection gap. Tests if structural>surface ranking and LP compression hold at smaller model scale on high-degeneracy dataset.\"}, \"exp_qwen3_4b_conll_scs_inference_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:41:33.501Z\", \"updated_at\": \"2026-05-18T20:49:03.705Z\", \"hypothesis\": \"CoNLL 4B SCS inference with best checkpoint-4200 (from resume training). Scale ablation: cross-scale evidence for correlation-selection gap. Compare vs v1 (ckpt-3800 baseline: greedy_f1=0.9251, SJ_rho=0.4045).\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-conll2003-merged-ckpt4200 --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_conll_scs_inference_v2\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-4B (LoRA checkpoint-4200 merged)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/qwen3-4b-conll2003-lora/checkpoint-4200\", \"gpu\": [\"cuda:1\"], \"checkpoint_path\": \"checkpoints/qwen3-4b-conll2003-merged-ckpt4200\", \"log_path\": \"/tmp/infer_4b_conll_v2.log\", \"account\": \"root\", \"backend\": \"tmux\", \"tmux_session\": \"exp_4b_conll_scs_v2\"}, \"metrics\": {\"greedy_f1\": 0.9234, \"oracle_f1\": 0.9404, \"oracle_headroom_pp\": 1.7, \"SJ_rho_full\": 0.4217, \"SJ_rho_cond\": 0.459, \"FK_rho_full\": 0.4181, \"FK_rho_cond\": 0.4538, \"LP_rho_full\": 0.3313, \"LP_rho_cond\": 0.3487, \"LP_auroc_full\": 0.7761, \"LP_auroc_cond\": 0.8209, \"n_instances\": 3453, \"verdict\": \"MARGINAL\", \"degen_rate\": 0.9057, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:54:14.575Z\", \"notes\": \"Gold-filter audit (2026-05-16): CONSISTENT. _full metrics (SJ_rho=0.4217, FK_rho=0.4181) are computed on gold-filtered set (n=2756), same as 8B Table 1 values. _full does NOT mean all 3453 instances — it means gold-nonempty instances. _cond further excludes greedy-F1=0 (n=2641). Confirmed via run_mvp_pilot.py source code and report.json n values.\"}, \"exp_qwen3_4b_scierc_scs_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:45:33.384Z\", \"updated_at\": \"2026-05-18T20:49:01.260Z\", \"hypothesis\": \"SciERC 4B SCS inference after v4 finetune merge. Complete 2x2 scale matrix (4B SciERC cell). Cross-scale + cross-task evidence for correlation-selection gap.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_scierc_scs_inference\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-4b-scierc-merged (checkpoint-400)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/qwen3-4b-scierc-merged\", \"eval_data\": \"scierc test set\"}, \"metrics\": {\"ner_greedy_f1\": 0.6612, \"ner_oracle_f1\": 0.7839, \"ner_headroom_pp\": 12.28, \"ner_SJ_rho\": 0.4221, \"ner_FK_rho\": 0.3258, \"ner_LP_rho\": 0.28, \"re_greedy_f1\": 0.4136, \"re_oracle_f1\": 0.5846, \"re_headroom_pp\": 17.1, \"re_SJ_rho\": 0.2673, \"re_FK_rho\": 0.3593, \"re_LP_rho\": 0.3512, \"re_sample_f1_pct_zero\": 0.476, \"re_LP_rho_cond\": 0.1135, \"re_LP_rho_cond_p\": 0.074, \"degen_rate\": 0.104, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"checkpoint_path\": \"checkpoints/qwen3-4b-scierc-merged/\", \"log_path\": \"/tmp/exp_qwen3_4b_scierc_scs_inference.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T20:00:03.730Z\"}, \"exp_027_fewnerd_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T05:28:57.036Z\", \"updated_at\": \"2026-05-18T20:48:58.455Z\", \"spec\": {\"hypothesis\": \"LP selection scales with N in low-degeneracy regime: N=16 should yield LP Δ > +2pp (vs N=8 +1.36pp) on Few-NERD (10% degen), because more samples increase oracle headroom while LP ranking remains effective.\", \"parent\": \"exp_021_fewnerd_full\", \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"data_path\": \"data/fewnerd_n16_subset/test.json\", \"data_count\": 5000, \"seed\": 42, \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd_n16_subset --dataset fewnerd --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs --start_index {0,1250,2500,3750} --end_index {1250,2500,3750,5000} --output_dir output/exp_027_fewnerd_n16/shard_{0-3}\", \"checkpoint_path\": \"output/exp_027_fewnerd_n16/sampled_results.jsonl\", \"log_path\": \"output/exp_027_fewnerd_n16/\"}, \"conclusion\": \"success\", \"metrics\": {\"LP_delta_pp\": 1.88, \"LP_delta_95CI\": [1.41, 2.37], \"degen_rate\": 0.0706, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"greedy_f1\": 0.7478, \"lp_sel_f1\": 0.7666, \"oracle_f1\": 0.902, \"headroom_pp\": 15.42, \"all_8_types_positive\": true, \"n_instances\": 5000, \"N_samples\": 16, \"bootstrap_p\": \"<0.001\"}, \"hypothesis\": \"LP selection scales with N in low-degeneracy regime: N=16 should yield LP Δ > +2pp (vs N=8 +1.36pp) on Few-NERD (10% degen), because more samples increase oracle headroom while LP ranking remains effective.\", \"completed_at\": \"2026-05-17T05:46:48.460Z\"}, \"exp_026_t12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T13:18:18.780Z\", \"updated_at\": \"2026-05-18T20:48:24.965Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --n_samples 8 --temperature 1.2 --seed 42 --max_tokens 1024 --collect_logprobs --output_dir output/exp_026_t12\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"log_path\": \"output/exp_026_t12.log\", \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\"}, \"conclusion\": \"success\", \"metrics\": {\"temperature\": 1.2, \"task\": \"T-ablation\", \"degen_rate\": 0.1493, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"completed_at\": \"2026-05-16T14:26:37.648Z\", \"hypothesis\": \"Temperature T=1.2 ablation on SciERC: test if higher temperature increases sample diversity (lower degeneracy) and LP discriminative range, potentially improving LP selection while maintaining structural signal effectiveness.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_026_t08\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:57:46.027Z\", \"updated_at\": \"2026-05-18T20:48:24.112Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_026_t08/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"temperature\": 0.8, \"task\": \"T-ablation\", \"degen_rate\": 0.2382, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"completed_at\": \"2026-05-16T14:26:36.243Z\", \"hypothesis\": \"Temperature T=0.8 ablation on SciERC: test if lower temperature increases LP compression (narrower range) while structural signals remain robust, supporting the claim that LP compression is intrinsic rather than temperature-driven.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_026_t05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:19:35.753Z\", \"updated_at\": \"2026-05-18T20:48:23.339Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_026_t05/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"temperature\": 0.5, \"task\": \"T-ablation\", \"degen_rate\": 0.414, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"completed_at\": \"2026-05-16T14:26:34.808Z\", \"hypothesis\": \"Temperature T=0.5 ablation on SciERC: extreme low temperature expected to maximally compress LP scores and increase degeneracy, providing upper-bound evidence for LP compression as model-intrinsic phenomenon.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_026_T12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T09:38:31.060Z\", \"updated_at\": \"2026-05-18T20:48:22.668Z\", \"hypothesis\": \"T=1.2 will decrease degeneracy rate and expand LP range vs T=1.0, but may degrade generation quality (lower greedy F1). Tests whether reducing degeneracy via higher T recovers selection headroom or if quality degradation offsets the benefit.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-17T09:39:51.733Z\", \"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.2 --seed 42 --output_dir output/exp_026_T12/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T12_run.log\\\"\", \"finished_at\": \"2026-05-17T09:48:04.019Z\", \"training_hours\": 0.14}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.2 --seed 42 --output_dir output/exp_026_T12/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T12_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"381369\", \"log_path\": \"output/exp_026_T12_run.log\", \"submitted_at\": \"2026-05-17T09:41:39.393Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"output/exp_026_T12/\", \"wall_clock_seconds\": 1114.4, \"gpu_hours\": 0.31}, \"pid\": \"381369\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_T12.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T09:48:08.312470+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.1493, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"lp_range_mean\": 0.075, \"lp_range_std\": 0.059, \"within_instance_rho_mean\": 0.2245, \"within_instance_rho_median\": 0.3152, \"within_instance_rho_valid_pct\": 0.875, \"greedy_f1\": 0.62, \"oracle_f1\": 0.758, \"lp_sel_f1\": 0.621, \"sj_sel_f1\": 0.597, \"em_sel_f1\": 0.596, \"vc_sel_f1\": 0.582, \"sj_rho\": 0.384, \"fk_rho\": 0.386, \"lp_rho\": 0.182, \"vc_rho\": 0.342, \"sj_auroc\": 0.683, \"lp_auroc\": 0.566}, \"completed_at\": \"2026-05-17T10:00:13.771Z\"}, \"exp_026_T08\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T09:38:29.602Z\", \"updated_at\": \"2026-05-18T20:48:21.975Z\", \"hypothesis\": \"T=0.8 will show intermediate degeneracy between T=0.5 and T=1.0, establishing a monotonic degeneracy-temperature relationship. If LP selection improves at T=0.8 vs T=1.0, it identifies the optimal operating point for the selection mechanism.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-17T09:39:50.780Z\", \"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.8 --seed 42 --output_dir output/exp_026_T08/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T08_run.log\\\"\", \"finished_at\": \"2026-05-17T09:47:56.543Z\", \"training_hours\": 0.13}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.8 --seed 42 --output_dir output/exp_026_T08/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T08_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"380680\", \"log_path\": \"output/exp_026_T08_run.log\", \"submitted_at\": \"2026-05-17T09:41:20.812Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"output/exp_026_T08/\", \"wall_clock_seconds\": 1131.4, \"gpu_hours\": 0.31}, \"pid\": \"380680\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_T08.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T09:48:02.635244+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.2382, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"lp_range_mean\": 0.043, \"lp_range_std\": 0.042, \"within_instance_rho_mean\": 0.1701, \"within_instance_rho_median\": 0.2635, \"within_instance_rho_valid_pct\": 0.728, \"greedy_f1\": 0.616, \"oracle_f1\": 0.737, \"lp_sel_f1\": 0.627, \"sj_sel_f1\": 0.619, \"em_sel_f1\": 0.611, \"vc_sel_f1\": 0.603, \"sj_rho\": 0.378, \"fk_rho\": 0.34, \"lp_rho\": 0.212, \"vc_rho\": 0.352, \"sj_auroc\": 0.662, \"lp_auroc\": 0.571}, \"completed_at\": \"2026-05-17T10:00:12.248Z\"}, \"exp_026_T05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T09:38:28.066Z\", \"updated_at\": \"2026-05-18T20:48:16.286Z\", \"hypothesis\": \"T=0.5 will increase degeneracy rate (more deterministic outputs) and compress LP range on SciERC, reducing selection headroom. Maps the low-temperature end of the degeneracy-temperature frontier, validating that degeneracy is regime-dependent on sampling temperature.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.5 --seed 42 --output_dir output/exp_026_T05/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T05_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"380188\", \"log_path\": \"output/exp_026_T05_run.log\", \"submitted_at\": \"2026-05-17T09:40:51.787Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"output/exp_026_T05/\", \"wall_clock_seconds\": 1158.3, \"gpu_hours\": 0.32}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": \"380188\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_T05.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.5 --seed 42 --output_dir output/exp_026_T05/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T05_run.log\\\"\", \"finished_at\": \"2026-05-17T09:47:31.332Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T09:47:35.127151+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.414, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"lp_range_mean\": 0.022, \"lp_range_std\": 0.021, \"within_instance_rho_mean\": 0.1306, \"within_instance_rho_median\": 0.2182, \"within_instance_rho_valid_pct\": 0.597, \"greedy_f1\": 0.617, \"oracle_f1\": 0.71, \"lp_sel_f1\": 0.622, \"sj_sel_f1\": 0.622, \"em_sel_f1\": 0.619, \"vc_sel_f1\": 0.61, \"sj_rho\": 0.333, \"fk_rho\": 0.341, \"lp_rho\": 0.208, \"vc_rho\": 0.353, \"sj_auroc\": 0.644, \"lp_auroc\": 0.577}, \"completed_at\": \"2026-05-17T10:00:10.083Z\"}, \"exp_017_llama_conll_n16_s123_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:02.953Z\", \"updated_at\": \"2026-05-18T20:47:52.122Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed123.\", \"parent\": \"exp_017_llama_conll_n16_s123\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 123, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_s123_r1024\", \"data_path\": \"data/conll2003\", \"data_count\": 3453}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T01:20:51.219Z\", \"notes\": \"Output exists on autodl-5090. Registry status corrected from killed to success.\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=123 (max_tokens=1024 rerun): cross-model multi-seed validation. Confirms structural>surface ordering is stable across seeds for LLaMA on CoNLL after gold-filtering correction.\", \"metrics\": {\"degen_rate\": 0.8636, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_018_llama_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:14.370Z\", \"updated_at\": \"2026-05-18T20:47:51.435Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: LLaMA SciERC N=8 seed=123, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 123 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_llama_scierc_seed123\", \"server\": \"autodl-5090\", \"seed\": 123, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed123/\", \"log_path\": \"output/exp_018_llama_scierc_seed123.log\", \"samples_md5\": \"072eeca68236d46b4c5c84b945209abc\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:04.855Z\", \"hypothesis\": \"LLaMA SciERC seed=123: multi-seed cross-model validation. Complements seed42 for LLaMA 3-seed protocol on SciERC NER+RE signal rankings.\", \"metrics\": {\"degen_rate\": 0.2665, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_018_qwen_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:13.570Z\", \"updated_at\": \"2026-05-18T20:47:50.032Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: Qwen SciERC N=8 seed=456, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 456 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_qwen_scierc_seed456\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_qwen_scierc_seed456/\", \"log_path\": \"output/exp_018_qwen_scierc_seed456/run.log\", \"samples_md5\": \"46d0de47ad7693c07e7df3a77c90c3be\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:03.898Z\", \"hypothesis\": \"Qwen SciERC seed=456: multi-seed Qwen validation. Part of 3-seed protocol (seed42=exp_012_rerun_1024, seed123, seed456) for statistical significance of signal rankings.\", \"metrics\": {\"degen_rate\": 0.2042, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_018_qwen_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:12.747Z\", \"updated_at\": \"2026-05-18T20:47:49.306Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: Qwen SciERC N=8 seed=123, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 123 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_qwen_scierc_seed123\", \"server\": \"autodl-5090\", \"seed\": 123, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_qwen_scierc_seed123/\", \"log_path\": \"output/exp_018_qwen_scierc_seed123.log\", \"samples_md5\": \"866a59581dea56f4633149f0b18a31ae\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:02.954Z\", \"hypothesis\": \"Qwen SciERC seed=123: multi-seed Qwen validation. Part of 3-seed protocol (seed42=exp_012_rerun_1024, seed123, seed456) for statistical significance of signal rankings.\", \"metrics\": {\"degen_rate\": 0.172, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_epoch_dgs_analysis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:57.921Z\", \"updated_at\": \"2026-05-18T20:01:46.134Z\", \"hypothesis\": \"DGS benefit is strictly monotonic with degeneracy rate: higher degeneracy → greater DGS improvement, validating that degeneracy rate is the key gating signal\", \"spec\": {\"command\": \"python3 code/epoch_dgs_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/epoch_dgs_analysis_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/epoch_dgs_analysis_results.json\", \"completed_at\": \"2026-05-18T20:01:46.134Z\"}, \"exp_diagnostic_calibration\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:56.064Z\", \"updated_at\": \"2026-05-18T20:01:44.364Z\", \"hypothesis\": \"A 3-indicator regression model (degeneracy rate, LP-F1 correlation, LP range) can quantitatively predict the optimal LP selection delta for unseen instances\", \"spec\": {\"command\": \"python3 code/diagnostic_calibration.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/diagnostic_calibration_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/diagnostic_calibration_results.json\", \"completed_at\": \"2026-05-18T20:01:44.364Z\"}, \"exp_adaptive_temperature\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:52.771Z\", \"updated_at\": \"2026-05-18T20:01:42.646Z\", \"hypothesis\": \"Adjusting sampling temperature based on instance-level confidence indicators can improve output diversity-quality tradeoff\", \"spec\": {\"command\": \"python3 code/adaptive_temperature.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/adaptive_temperature_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/adaptive_temperature_results.json\", \"completed_at\": \"2026-05-18T20:01:42.646Z\"}, \"exp_entity_consensus\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:50.628Z\", \"updated_at\": \"2026-05-18T20:01:40.869Z\", \"hypothesis\": \"Constructing new output from N samples using entity frequency thresholds and LP-weighted decisions can capture complementary information that single-sample selection misses\", \"spec\": {\"command\": \"python3 code/entity_consensus.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/entity_consensus_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/entity_consensus_results.json\", \"completed_at\": \"2026-05-18T20:01:40.869Z\"}, \"exp_ccs_selection\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:48.671Z\", \"updated_at\": \"2026-05-18T20:01:39.128Z\", \"hypothesis\": \"Three-stage cascaded selection (degen→greedy, low-LP-range→entity MV, high-LP-range→LP) can outperform single-strategy selection by adapting to local confidence patterns\", \"spec\": {\"command\": \"python3 code/ccs_selection.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/ccs_selection_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/ccs_selection_results.json\", \"completed_at\": \"2026-05-18T20:01:39.128Z\"}, \"exp_017_llama_conll\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T14:39:32.014Z\", \"updated_at\": \"2026-05-18T19:11:03.240Z\", \"completed_at\": \"2026-05-14T17:12:15.687Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"success\"}}, \"hypothesis\": \"On CoNLL (high degeneracy regime), LLaMA should show the same pattern as Qwen3: LP selection fails due to narrow headroom, but structural signals retain diagnostic value (QE rho). Cross-model validation of the degeneracy-driven signal effectiveness framework.\", \"parent\": \"exp_007_llama_inference\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-17T11:30:53.467Z\"}, \"metrics\": {\"degeneracy_cf1_gold_filtered\": 0.894, \"n_constant_f1\": 2465, \"n_gold_filtered\": 2756, \"n_total\": 3453, \"greedy_f1\": 0.9239, \"oracle_f1\": 0.9451, \"random_f1\": 0.9207, \"headroom_pp\": 2.11, \"dgs_f1\": 0.9254, \"dgs_delta_pp\": 0.14, \"dgs_nondegen_lp_delta_pp\": 1.37, \"selection_f1\": {\"SJ\": {\"f1\": 0.9237, \"delta_pp\": -0.04}, \"FK\": {\"f1\": 0.924, \"delta_pp\": -0.02}, \"VC\": {\"f1\": 0.925, \"delta_pp\": 0.08}, \"EM\": {\"f1\": 0.9244, \"delta_pp\": 0.02}, \"LP\": {\"f1\": 0.9244, \"delta_pp\": 0.02}}, \"qe_rho_full_3seed\": {\"SJ\": {\"mean\": 0.4631, \"sd\": 0.0074}, \"FK\": {\"mean\": 0.4546, \"sd\": 0.0061}, \"EM\": {\"mean\": 0.4603, \"sd\": 0.0078}, \"VC\": {\"mean\": 0.4579, \"sd\": 0.003}, \"LP\": {\"mean\": 0.3099, \"sd\": 0.0055}}, \"qe_auroc_full_3seed\": {\"SJ\": {\"mean\": 0.736, \"sd\": 0.0064}, \"FK\": {\"mean\": 0.732, \"sd\": 0.0063}, \"EM\": {\"mean\": 0.7355, \"sd\": 0.0069}, \"VC\": {\"mean\": 0.7394, \"sd\": 0.0041}, \"LP\": {\"mean\": 0.7629, \"sd\": 0.0044}}, \"lp_range\": {\"mean\": 0.0198, \"std\": 0.0315, \"median\": 0.0002}}, \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/exp017_full_signal_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/samples.jsonl\", \"data_count\": 3453, \"model_name\": \"llama3.1-8b-conll2003-merged\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/full_signal_analysis.json\"}}, \"exp_017_llama_conll_finetune\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:47:36.156Z\", \"updated_at\": \"2026-05-18T18:43:42.649Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli train train_config_llama_conll2003_3ep.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"674921\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_017_llama_conll_finetune.log\", \"submitted_at\": \"2026-05-18T16:47:35.786Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003/llmfactory_train.json\", \"data_count\": 14037, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/llama3.1-8b-conll2003-lora-3ep\", \"checkpoint_source\": \"Meta-Llama-3.1-8B-Instruct (base model, LoRA from scratch)\", \"eval_data\": \"conll2003_uie_dev\", \"wall_clock_seconds\": 6176.5, \"gpu_hours\": 1.72}, \"hypothesis\": \"Structural self-consistency QE signals (SJ, FK, VC, EM) show model-agnostic diagnostic power: their Spearman rho with per-instance F1 should be comparable on LLaMA 3.1-8B as on Qwen 2.5-7B for CoNLL-2003 NER, even though degeneracy rates and absolute F1 may differ.\", \"parent\": \"exp_llama_fewnerd_lora\", \"conclusion\": \"success\", \"metrics\": {\"degeneracy_rate\": 0.853, \"greedy_f1\": 0.928, \"oracle_f1\": 0.951, \"headroom\": 0.023, \"selection_f1\": 0.934, \"full_rho_SJ\": 0.45, \"full_rho_FK\": 0.443, \"full_rho_VC\": 0.437, \"full_rho_EM\": 0.448, \"full_rho_LP\": 0.273, \"full_AUROC_SJ\": 0.752, \"full_AUROC_EM\": 0.753, \"full_AUROC_LP\": 0.739, \"cond_rho_SJ\": 0.454, \"cond_rho_EM\": 0.458, \"cond_rho_LP\": 0.311, \"cond_AUROC_EM\": 0.783, \"cond_AUROC_LP\": 0.804}, \"completed_at\": \"2026-05-18T18:30:32.331Z\"}, \"exp_028_entity_token_lp\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:22:18.594Z\", \"updated_at\": \"2026-05-18T18:23:06.601Z\", \"hypothesis\": \"Full-sequence mean LP underperforms as a quality signal because format/schema tokens dilute the entity-relevant logprob signal; isolating entity-only tokens should yield higher QE correlation and selection F1.\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"python code/exp028_entity_token_lp_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_entity_token_lp/scierc/samples.jsonl\", \"data_count\": 529, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_028_entity_token_lp/analysis_results.json\"}, \"completed_at\": \"2026-05-18T18:22:59.312Z\", \"metrics\": {\"greedy_f1\": 0.643, \"oracle_f1\": 0.7845, \"full_lp_global_rho\": 0.2971, \"entity_text_type_lp_global_rho\": 0.4401, \"full_lp_selection_f1\": 0.6465, \"entity_text_type_lp_selection_f1\": 0.6357, \"dilution_ratio\": 0.32, \"full_lp_within_range_median\": 0.0402, \"entity_text_type_within_range_median\": 0.1346, \"schema_only_within_range_median\": 0.0089}}, \"exp_026_t12_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:28:36.812Z\", \"updated_at\": \"2026-05-18T15:30:33.407Z\", \"hypothesis\": \"Higher temperature (T=1.2) reduces degeneracy rate and increases LP range on SciERC NER, but may degrade absolute generation quality\", \"spec\": {\"command\": \"python code/analyze_exp026_temp_5signal.py --data_path output/exp_026_t12/samples.jsonl --output_dir output/exp_026_t12/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"665522\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_t12_scierc.log\", \"submitted_at\": \"2026-05-18T15:28:56.997Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"output/exp_026_t12/samples.jsonl\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"checkpoint_source\": \"ft_002_v2\", \"eval_data\": \"scierc_test_551\", \"wall_clock_seconds\": 96.4, \"gpu_hours\": 0.03}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T15:30:33.407Z\"}, \"exp_026_t08_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:28:36.084Z\", \"updated_at\": \"2026-05-18T15:30:31.219Z\", \"hypothesis\": \"Moderate temperature (T=0.8) provides intermediate degeneracy/LP-range tradeoff on SciERC NER, testing sensitivity of structural signals to temperature\", \"spec\": {\"command\": \"python code/analyze_exp026_temp_5signal.py --data_path output/exp_026_t08/samples.jsonl --output_dir output/exp_026_t08/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"665386\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_t08_scierc.log\", \"submitted_at\": \"2026-05-18T15:28:55.394Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"output/exp_026_t08/samples.jsonl\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"checkpoint_source\": \"ft_002_v2\", \"eval_data\": \"scierc_test_551\", \"wall_clock_seconds\": 95.8, \"gpu_hours\": 0.03}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T15:30:31.219Z\"}, \"exp_026_t05_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:28:34.135Z\", \"updated_at\": \"2026-05-18T15:30:28.965Z\", \"hypothesis\": \"Lower temperature (T=0.5) increases degeneracy rate and reduces LP range on SciERC NER, as reduced sampling diversity causes more identical outputs\", \"spec\": {\"command\": \"python code/analyze_exp026_temp_5signal.py --data_path output/exp_026_t05/samples.jsonl --output_dir output/exp_026_t05/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"665248\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_t05_scierc.log\", \"submitted_at\": \"2026-05-18T15:28:53.787Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"output/exp_026_t05/samples.jsonl\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"checkpoint_source\": \"ft_002_v2\", \"eval_data\": \"scierc_test_551\", \"wall_clock_seconds\": 95.2, \"gpu_hours\": 0.03}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T15:30:28.965Z\"}, \"exp_027_mlp_verifier\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:39:22.524Z\", \"updated_at\": \"2026-05-18T06:41:51.069Z\", \"metrics\": {\"lr_auroc\": 0.6522, \"mlp_auroc\": 0.6381, \"rf_auroc\": 0.5868, \"mlp_15feat_auroc\": 0.6341, \"lr_sel_f1\": 0.6406, \"mlp_sel_f1\": 0.6278, \"greedy_f1\": 0.6441, \"oracle_f1\": 0.8231, \"best_single_signal_auroc\": 0.6476, \"feature_bottleneck_confirmed\": true}, \"hypothesis\": \"MLP/RF等非线性模型能否通过组合5个QE信号(LP,SJ,FK,EM,VC)超越LR，或通过cross-signal interactions提取额外信息，从而缩小selection gap\", \"spec\": {\"command\": \"python train_mlp_verifier.py --n_samples 16 --cv_folds 5 --seeds 42,123,456\", \"server\": \"a100\", \"data_path\": \"output/exp_001_n16_seed*/samples.jsonl\", \"data_count\": 529, \"model_name\": \"sklearn LR/MLP/RF\", \"seed\": \"42,123,456\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp_027_mlp_verifier/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T06:41:51.069Z\"}, \"exp_028_fewnerd_5epoch\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T07:53:12.913Z\", \"updated_at\": \"2026-05-17T20:29:42.274Z\", \"spec\": {\"hypothesis\": \"Few-NERD low degeneracy (10%) partially due to under-convergence at 3 epochs. 5 epochs should increase degeneracy as model becomes more confident, potentially reducing LP selection gain.\", \"parent\": \"exp_021_fewnerd_full\", \"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0,1,2,3 llamafactory-cli train train_config_fewnerd_5epoch_4gpu.yaml 2>&1 | tee logs/exp_028_4gpu_train.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,1,2,3\", \"data_path\": \"data/fewnerd_uie_train\", \"data_count\": 131767, \"model_name\": \"Qwen3-8B LoRA rank=32\", \"seed\": 42, \"log_path\": \"logs/exp_028_4gpu_train.log\", \"checkpoint_path\": \"checkpoints/qwen3-8b-fewnerd-5epoch-lora\"}, \"conclusion\": \"negative\", \"metrics\": {\"degeneracy_cf1_gold\": 0.3133, \"greedy_f1\": 0.7773, \"lp_sel_delta_pp\": 0.624, \"lp_sel_f1\": 0.7835, \"oracle_f1\": 0.8723, \"within_instance_rho_mean\": 0.4066, \"within_instance_rho_median\": 0.6151}, \"hypothesis\": \"Few-NERD low degeneracy (10%) partially due to under-convergence at 3 epochs. 5 epochs should increase degeneracy as model becomes more confident, potentially reducing LP selection gain.\", \"completed_at\": \"2026-05-17T20:29:42.274Z\"}, \"exp_028\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T07:35:39.447Z\", \"updated_at\": \"2026-05-17T20:26:59.399Z\", \"hypothesis\": \"Few-NERD low degeneracy (10%) in exp-021 is NOT due to under-convergence at 3 epochs; training for 5 epochs will show similar degeneracy levels, confirming the structural property of this dataset rather than an artifact of insufficient training.\", \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"completed_at\": \"2026-05-17T12:09:43.334Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}, \"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T20:06:01.040147+00:00\"}]}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0,1,2,3 llamafactory-cli train train_config_fewnerd_5epoch_4gpu.yaml 2>&1 | tee logs/exp_028_4gpu_train.log\\\"\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd_uie_train\", \"data_count\": 131767, \"model_name\": \"Qwen3-8B LoRA rank=32\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-fewnerd-5epoch-lora\", \"log_path\": \"logs/exp_028_4gpu_train.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T20:05:57.260Z\"}, \"conclusion\": \"negative\", \"metrics\": {\"degeneracy_cf1_gold\": 0.313, \"greedy_f1\": 0.7773, \"lp_sel_f1\": 0.7835, \"lp_sel_delta_pp\": 0.62, \"oracle_f1\": 0.8723, \"within_instance_rho\": 0.4066, \"train_loss\": 0.0189, \"eval_loss\": 0.0311}}, \"exp_024_claim_audit\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:54:36.291Z\", \"updated_at\": \"2026-05-17T10:55:08.244Z\", \"hypothesis\": \"Systematic cross-chapter numerical consistency audit: verify all quantitative claims in paper against source experiment data, catch stale values and cross-reference errors before submission.\", \"conclusion\": \"success\", \"metrics\": {\"consistent\": 97, \"errors\": 1, \"warnings\": 5, \"old_residuals_found\": 0}, \"spec\": {\"checkpoint_path\": \"artifacts/exp_024_claim_audit/audit_report.md\", \"log_path\": \"N/A\", \"command\": \"CPU-only paper audit\", \"server\": \"local\", \"data_path\": \"docs/paper/\", \"data_count\": 0, \"model_name\": \"N/A\", \"seed\": 0}, \"completed_at\": \"2026-05-17T10:55:08.244Z\"}, \"exp_016_rerun_1024_bootstrap\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:44:21.577Z\", \"updated_at\": \"2026-05-17T03:33:39.786Z\", \"hypothesis\": \"3-seed bootstrap significance test for NER logprob vs greedy selection gap (+0.6pp). Tests whether the observed advantage is statistically significant.\", \"spec\": {\"command\": \"python code/bootstrap_significance.py\", \"server\": \"local\", \"data_path\": \"output/exp_016_rerun_1024/\", \"data_count\": 529, \"model_name\": \"N/A (statistical analysis)\", \"seed\": \"3-seed bootstrap (1000 iterations)\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp_016_rerun_1024_bootstrap/\"}, \"conclusion\": \"negative\", \"metrics\": {\"bootstrap_ci_95\": [-0.03, 0.042], \"permutation_p\": 0.39, \"cohen_d\": 0.038, \"sign_test_win_rate\": 0.466, \"ner_logprob_vs_greedy_delta\": 0.006, \"conclusion_summary\": \"NER selection: no signal significantly outperforms greedy; RE: same conclusion\"}, \"completed_at\": \"2026-05-14T23:44:48.818Z\", \"parent\": \"exp_016_rerun_1024\"}, \"exp_verbalized_confidence\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:45:20.552Z\", \"updated_at\": \"2026-05-17T03:33:39.197Z\", \"hypothesis\": \"Verbalized confidence baseline: let model self-rate extraction confidence. If also compressed → strengthens \\\"score compression is general\\\" claim. If effective → important positive finding requiring narrative adjustment.\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_verbalized_confidence.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_rerun_1024/samples.jsonl + output/exp002_conll2003/samples.jsonl\", \"data_count\": 3285, \"model_name\": \"qwen3-8b-scierc-merged-v2 + qwen3-8b-conll2003-merged\", \"seed\": 42, \"checkpoint_path\": \"output/review_round9_experiments/verbalized_confidence/\", \"log_path\": \"output/review_round9_experiments/verbalized_confidence_run.log\"}, \"completed_at\": \"2026-05-16T03:09:39.916Z\", \"metrics\": {\"scierc\": {\"VerbConf_rho\": 0.2965, \"VerbConf_auroc\": 0.6811, \"VerbConf_sel_f1\": 0.6195, \"VerbConf_delta\": -0.0245, \"best_existing_rho\": 0.3792, \"VerbConf_mean\": 8.58, \"VerbConf_std\": 1.15, \"parse_fail_rate\": 0.0026}, \"conll\": {\"VerbConf_rho\": 0.3366, \"VerbConf_auroc\": 0.7469, \"VerbConf_sel_f1\": 0.8886, \"VerbConf_delta\": -0.0193, \"best_existing_rho\": 0.4507, \"VerbConf_mean\": 9.24, \"VerbConf_std\": 1.32, \"parse_fail_rate\": 0}}, \"parent\": \"exp_012_rerun_1024\"}, \"exp_entity_token_lp\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T05:39:44.631Z\", \"updated_at\": \"2026-05-17T03:33:38.371Z\", \"hypothesis\": \"Entity-token LP: test Discussion hypothesis (d) format-token dilution. Re-inference with per-token logprobs, then compute entity-only LP variance and selection F1. If entity-token LP compression is reduced → pilot remedy for LP selection. Also includes LP z-score normalization as zero-cost baseline. Addresses SF2+SF3 from Round 12.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1\", \"started_at\": \"2026-05-16T05:41:33.768Z\"}, \"conclusion\": \"negative\", \"metrics\": {\"scierc_ner\": {\"greedy_f1\": 0.643, \"full_lp_sel_f1\": 0.6465, \"entity_lp_sel_f1\": 0.6262, \"oracle_f1\": 0.7845, \"entity_lp_delta_vs_full_lp\": -0.0203}, \"conll_ner\": {\"greedy_f1\": 0.9065, \"full_lp_sel_f1\": 0.8989, \"entity_lp_sel_f1\": 0.8659, \"oracle_f1\": 0.948, \"entity_lp_delta_vs_full_lp\": -0.033}, \"finding\": \"entity-token LP strictly worse than full-sequence LP; CoNLL entity tokens saturated (79.4% tied), SciERC entity tokens too sparse (5.3% of total)\"}, \"spec\": {\"command\": \"python analyze_entity_token_lp.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_rerun_1024/ + output/exp_002_conll_rerun_1024/\", \"data_count\": \"529 (SciERC NER) + 2756 (CoNLL NER)\", \"model_name\": \"Qwen3-8B (finetuned)\", \"seed\": 42, \"checkpoint_path\": \"artifacts/exp_entity_token_lp/results.json\", \"log_path\": \"artifacts/exp_entity_token_lp/report.md\"}, \"completed_at\": \"2026-05-16T06:28:46.845Z\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_freeform_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:42:22.868Z\", \"updated_at\": \"2026-05-17T03:33:37.623Z\", \"spec\": {\"command\": \"python run_freeform_inference.py --seed 42 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"169042\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_ablation.log\", \"submitted_at\": \"2026-05-15T09:42:30.236Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"hypothesis\": \"Free-form decoding recovers logprob variance and selection ability lost under constrained decoding\", \"plan_id\": \"exp-018\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"tmux_session\": \"exp_freeform_ablation\", \"wall_clock_seconds\": 1059.0, \"gpu_hours\": 0.29}, \"conclusion\": \"negative\", \"metrics\": {\"lp_std_ratio_free_vs_constrained\": 0.97, \"lp_range_ratio\": 0.96, \"tied_fraction_constrained\": 0.597, \"tied_fraction_freeform\": 0.577, \"ner_selection_gap_constrained\": 0.0059, \"ner_selection_gap_freeform\": 0.0018, \"re_selection_gap_constrained\": -0.0068, \"re_selection_gap_freeform\": 0.0169, \"parse_rate\": 0.9995, \"ner_vc_rho_constrained\": 0.3792, \"ner_vc_rho_freeform\": 0.4089}, \"checkpoint_path\": \"N/A (inference-only experiment)\", \"completed_at\": \"2026-05-15T10:00:09.238Z\", \"hypothesis\": \"Free-form vs constrained decoding ablation on SciERC: test if removing JSON schema constraint changes LP variance distribution. If LP remains compressed under free-form, confirms compression is model-intrinsic not format-artifact.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_008_re_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:03:06.876Z\", \"updated_at\": \"2026-05-17T02:58:19.490Z\", \"spec\": {\"hypothesis\": \"RE N=16 confirms negative finding with higher statistical power. If rho still <0.30, task-complexity boundary is robust.\", \"plan_id\": \"exp-008\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"gpu\": \"cuda:2\", \"server\": \"gpu-5090-4x-2\", \"gpu_budget_hours\": 12, \"description\": \"RE N=16 on SciERC to confirm negative finding. Inference with log-prob capture.\", \"priority\": \"P1\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"seed\": 42, \"num_instances\": 200, \"partial\": true, \"note\": \"Only 200/551 instances due to --num_test default bug. Needs full rerun.\"}, \"metrics\": {\"ner\": {\"greedy_f1\": 0.6635, \"oracle_f1\": 0.8208, \"headroom\": 0.1572, \"rho_sj_full\": 0.377, \"rho_fk_full\": 0.2508, \"rho_logprob_full\": 0.3153, \"rho_sj_cond\": 0.3598, \"rho_fk_cond\": 0.2251, \"rho_logprob_cond\": 0.2927, \"sj_beats_fk\": true, \"rho_advantage\": 0.1262}, \"re\": {\"greedy_f1\": 0.4339, \"oracle_f1\": 0.6658, \"headroom\": 0.2319, \"rho_sj_full\": 0.2966, \"rho_fk_full\": 0.2871, \"rho_logprob_full\": 0.2986, \"rho_sj_cond\": 0.3975, \"rho_fk_cond\": 0.3774, \"rho_logprob_cond\": 0.2745, \"sj_beats_fk\": true, \"rho_advantage\": 0.0095}, \"verdict\": \"FAIL\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp008_re_n16/\", \"completed_at\": \"2026-05-14T12:28:39.268Z\", \"hypothesis\": \"RE N=16 initial evaluation: first relation extraction test with structural signals. Establishes baseline RE signal effectiveness before pipeline corrections.\"}, \"exp_001_ner_n16_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:46:06.430Z\", \"updated_at\": \"2026-05-17T02:58:18.225Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=3 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --output_dir output/exp001_n16_seed123 --num_test 9999 --collect_logprobs 2>&1 | tee output/exp001_n16_seed123_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"63407\", \"log_path\": \"output/exp001_n16_seed123_run.log\", \"submitted_at\": \"2026-05-14T12:46:06.234Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 551, \"data_path\": \"data/scierc/processed_data\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"checkpoint_path\": \"output/exp001_n16_seed123/\", \"wall_clock_seconds\": 2748.0, \"gpu_hours\": 0.76}, \"conclusion\": \"success\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.663, \"oracle_f1\": 0.809, \"headroom\": 0.146, \"rho_sj\": 0.423, \"rho_fk\": 0.29, \"rho_logprob\": 0.239, \"rho_sj_cond\": 0.423, \"rho_fk_cond\": 0.26}, \"re\": {\"greedy_f1\": 0.419, \"oracle_f1\": 0.625, \"headroom\": 0.206, \"rho_sj\": 0.267, \"rho_fk\": 0.315, \"rho_sj_cond\": 0.364, \"rho_fk_cond\": 0.331}, \"verdict\": \"FAIL\", \"verdict_note\": \"RE rho_sj=0.267 < 0.40; RE >30% samples F1=0\", \"n_instances\": 551, \"seed\": 123, \"N\": 16, \"T\": 1}, \"completed_at\": \"2026-05-14T13:31:54.232Z\", \"hypothesis\": \"SciERC NER N=16 seed=123: multi-seed validation at N=16. Tests seed stability for signal rankings with more samples.\"}, \"exp_007_ner_multi_model\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:20.748Z\", \"updated_at\": \"2026-05-17T02:58:16.747Z\", \"spec\": {\"command\": \"bash -c 'source env.sh && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_llama.yaml'\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"60970\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\", \"submitted_at\": \"2026-05-14T12:43:09.108Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data\", \"data_count\": 1861, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 42, \"log_file\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\", \"wall_clock_seconds\": 165.8, \"gpu_hours\": 0.05}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-14T11:43:50.977Z\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:45:54.952Z\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/llama3.1-8b-scierc-lora\", \"metrics\": {\"epoch\": 5, \"train_loss\": 0.0767, \"eval_loss\": 0.1049, \"train_runtime_sec\": 1494.5, \"train_samples_per_second\": 6.226, \"checkpoints\": [\"checkpoint-400\", \"checkpoint-500\", \"checkpoint-585\"], \"base_model\": \"Meta-Llama-3.1-8B-Instruct\", \"lora_r\": 32, \"lora_alpha\": 64, \"note\": \"EXIT_CODE=129 (SIGHUP) but training completed all 5 epochs before signal. Checkpoint fully intact.\"}, \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\", \"hypothesis\": \"Multi-model NER comparison: evaluates signal effectiveness across Qwen and LLaMA on SciERC NER. Establishes cross-model generalization of structural>surface ranking.\"}, \"exp_003_ner_wnut17\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:17.544Z\", \"updated_at\": \"2026-05-17T02:58:14.928Z\", \"spec\": {\"merged_model_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-merged\", \"pilot_command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-wnut17-merged --data_dir data/wnut17 --dataset wnut17 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp003_wnut17_pilot --num_test 9999 --collect_logprobs\", \"pilot_pid\": 71498, \"pilot_server\": \"autodl-5090\", \"pilot_started_at\": \"2026-05-14T21:36:00Z\", \"test_samples\": 1287}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-14T11:43:50.537Z\", \"finished_at\": \"2026-05-14T12:53:13.262Z\", \"training_hours\": 1.16}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T12:53:14.768981+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-merged\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.525, \"oracle_f1\": 0.664, \"headroom\": 0.139, \"rho_sj_full\": 0.082, \"rho_fk_full\": 0.124, \"rho_logprob_full\": -0.414, \"rho_sj_cond\": 0.275, \"rho_fk_cond\": 0.164, \"rho_logprob_cond\": 0.352, \"sj_beats_logprob_cond\": false}, \"n_instances\": 1287, \"n_gold_empty\": 598, \"sample_f1_mean\": 0.401, \"sample_f1_pct_zero\": 53.7, \"N\": 16, \"T\": 1, \"seed\": 42, \"verdict\": \"FAIL\", \"verdict_note\": \">30% samples F1=0; structural rho weak; logprob baseline stronger\"}, \"conclusion\": \"negative\", \"log_path\": \"output/exp003_wnut17_pilot/\", \"completed_at\": \"2026-05-14T13:40:20.979Z\", \"hypothesis\": \"WNUT-17 NER fine-tune + inference: initial attempt on social media domain. Tests if structural signals work when model capability is low on noisy text with novel entity types.\"}, \"exp_001_seed456_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:41.067Z\", \"updated_at\": \"2026-05-17T02:58:12.996Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:05.416Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:05.021Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:10.317185+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.414, \"rho_fk\": 0.298}, \"re\": {\"rho_sj\": 0.268, \"rho_fk\": 0.26}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 456, \"source\": \"reviewer_verified_report_json\"}, \"hypothesis\": \"SciERC NER seed=456 T=1.0 full: early multi-seed NER test before pipeline corrections. Preliminary evidence for seed stability.\"}, \"exp_001_seed123_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:42.503Z\", \"updated_at\": \"2026-05-17T02:58:11.623Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:13.823Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:13.213Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:16.532801+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.417, \"rho_fk\": 0.283}, \"re\": {\"rho_sj\": 0.265, \"rho_fk\": 0.315}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 123, \"source\": \"reviewer_verified_report_json\"}, \"hypothesis\": \"SciERC NER seed=123 T=1.0 full: early multi-seed NER test before pipeline corrections. Preliminary evidence for seed stability.\"}, \"exp_008_re_n16_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:42.867Z\", \"updated_at\": \"2026-05-17T02:58:10.171Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:18.988Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:19.577Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:21.528032+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.444}, \"re\": {\"rho_sj\": 0.248}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 42, \"mode\": \"RE-only\", \"source\": \"director_corrected\"}, \"hypothesis\": \"RE N=16 T=1.0 full dataset: early RE evaluation attempt. Tests structural signals on relation extraction before pipeline corrections.\"}, \"exp_007_llama_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:54:48.055Z\", \"updated_at\": \"2026-05-17T02:58:03.014Z\", \"spec\": {\"command\": \"python run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp007_llama_inference/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"75172\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_llama_inference.log\", \"submitted_at\": \"2026-05-14T13:54:47.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Meta-Llama-3.1-8B-Instruct (LoRA fine-tuned on SciERC)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/llama3.1-8b-scierc-merged\", \"description\": \"LLaMA-3.1-8B SciERC joint inference (NER+RE) with 8 samples, T=1.0, logprobs collected.\", \"wall_clock_seconds\": 1038.5, \"gpu_hours\": 0.29}, \"log_path\": \"output/exp007_llama_inference/\", \"checkpoint_path\": \"N/A\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.66, \"oracle_f1\": 0.781, \"headroom\": 0.121, \"rho_fk\": 0.327, \"rho_sj\": 0.363, \"rho_fk_cond\": 0.226, \"rho_sj_cond\": 0.311, \"rho_logprob\": 0.183, \"rho_logprob_cond\": 0.109, \"structural_beats_surface\": true, \"sample_f1_pct_zero\": 11.6}, \"re\": {\"greedy_f1\": 0.434, \"oracle_f1\": 0.568, \"headroom\": 0.135, \"rho_fk\": 0.305, \"rho_sj\": 0.299, \"rho_fk_cond\": 0.259, \"rho_sj_cond\": 0.405, \"rho_logprob\": 0.288, \"rho_logprob_cond\": 0.092, \"structural_beats_surface\": false, \"sample_f1_pct_zero\": 41.2}, \"n_instances\": 551, \"N\": 8, \"T\": 1, \"seed\": 42, \"model\": \"LLaMA-3.1-8B-Instruct\", \"verdict\": \"FAIL\", \"verdict_note\": \"RE rho_sj_full=0.299 < 0.40; >30% RE samples F1=0\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T14:12:06.442Z\", \"hypothesis\": \"LLaMA SciERC N=8 baseline: first cross-model test. Verifies structural signal effectiveness generalizes from Qwen to LLaMA model family on SciERC NER.\"}, \"exp_003_wnut17_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:47:34.654Z\", \"updated_at\": \"2026-05-17T02:58:01.627Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-wnut17-merged --data_dir data/wnut17 --dataset wnut17 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp003_wnut17_eval --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/wnut17\", \"data_count\": 1287, \"model_name\": \"qwen3-8b-wnut17-merged\", \"seed\": 42}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T14:08:17.429Z\", \"metrics\": {\"greedy_f1\": 0.523, \"oracle_f1\": 0.664, \"headroom\": 0.141, \"rho_fk\": 0.125, \"rho_sj\": 0.089, \"rho_fk_cond\": 0.169, \"rho_sj_cond\": 0.288, \"rho_logprob_full\": -0.409, \"rho_logprob_cond\": 0.35, \"structural_beats_surface\": false, \"sample_f1_pct_zero\": 53.7, \"n_instances\": 1287, \"N\": 16, \"T\": 1, \"seed\": 42, \"model\": \"Qwen3-8B\", \"n_gold_empty_filtered\": 598, \"verdict\": \"FAIL\", \"verdict_note\": \"structural_beats_surface=false; >50% samples F1=0\"}, \"hypothesis\": \"WNUT-17 NER evaluation: initial test on noisy social media domain. Tests boundary conditions for structural signal effectiveness on out-of-domain text.\"}, \"exp_010_selection_curves\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:01:53.585Z\", \"updated_at\": \"2026-05-17T02:58:00.378Z\", \"spec\": {\"command\": \"python3 code/exp010_selection_curves.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2, output/exp_008_re_n16_v2, output/exp002_conll2003\", \"data_count\": \"551+397+3453 instances\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"description\": \"Best-of-N selection curves: F1 vs N for 7 signals across 3 datasets\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"/tmp/exp010.log\", \"completed_at\": \"2026-05-14T15:02:22.638Z\", \"metrics\": {\"scierc_ner\": {\"n_instances\": 551, \"greedy_f1\": 0.618, \"N16\": {\"oracle\": 0.787, \"SJ\": 0.62, \"FK\": 0.621, \"logprob\": 0.621, \"voting_conf\": 0.585, \"EM\": 0.606, \"random\": 0.595}, \"N8\": {\"oracle\": 0.752, \"SJ\": 0.614, \"FK\": 0.614, \"logprob\": 0.619, \"voting_conf\": 0.591, \"EM\": 0.603, \"random\": 0.589}, \"N4\": {\"oracle\": 0.714, \"SJ\": 0.607, \"FK\": 0.608, \"logprob\": 0.616, \"voting_conf\": 0.594, \"EM\": 0.6, \"random\": 0.587}}, \"scierc_re\": {\"n_instances\": 397, \"greedy_f1\": 0.403, \"N16\": {\"oracle\": 0.631, \"SJ\": 0.397, \"FK\": 0.396, \"logprob\": 0.41, \"voting_conf\": 0.408, \"EM\": 0.381, \"random\": 0.364}, \"N8\": {\"oracle\": 0.583, \"SJ\": 0.393, \"FK\": 0.394, \"logprob\": 0.413, \"voting_conf\": 0.398, \"EM\": 0.381, \"random\": 0.363}}, \"conll_ner\": {\"n_instances\": 3453, \"greedy_f1\": 0.725, \"N8\": {\"oracle\": 0.757, \"SJ\": 0.718, \"FK\": 0.717, \"logprob\": 0.716, \"voting_conf\": 0.714, \"EM\": 0.716, \"random\": 0.69}, \"N4\": {\"oracle\": 0.746, \"SJ\": 0.714, \"FK\": 0.714, \"logprob\": 0.715, \"voting_conf\": 0.714, \"EM\": 0.712, \"random\": 0.692}}}, \"hypothesis\": \"Selection curve analysis: plots selection F1 vs confidence threshold for each signal. Visualizes where correlation-selection gap emerges and at what confidence level signals become useful for filtering.\"}, \"exp_007_llama_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:50.628Z\", \"updated_at\": \"2026-05-17T02:57:59.595Z\", \"spec\": {\"description\": \"LLaMA 3.1-8B SciERC joint extraction, seed=456, cross-model robustness test\", \"hypothesis\": \"Structural consistency generalizes across model architectures (LLaMA vs Qwen)\", \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_seed456\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 456, \"gpu\": [\"cuda:2\"], \"backend\": \"tmux\", \"tmux_session\": \"exp007_s456\", \"account\": \"root\", \"log_path\": \"output/exp_007_llama_seed456/run.log\"}, \"conclusion\": \"negative\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed456/run.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed456/\", \"completed_at\": \"2026-05-14T15:19:20.693Z\", \"metrics\": {\"verdict\": \"FAIL\", \"ner\": {\"greedy_f1\": 0.6597, \"oracle_f1\": 0.7575, \"oracle_headroom\": 0.0978, \"fleiss_kappa\": 0.4543, \"soft_jaccard\": 0.7491, \"rho_kappa_f1\": 0.3115, \"rho_sj_f1\": 0.3663, \"structural_gt_surface\": true}, \"re\": {\"greedy_f1\": 0.4334, \"oracle_f1\": 0.5789, \"oracle_headroom\": 0.1455, \"fleiss_kappa\": 0.3791, \"soft_jaccard\": 0.6782, \"rho_kappa_f1\": 0.3013, \"rho_sj_f1\": 0.287, \"structural_gt_surface\": false}, \"logprob_ner\": {\"rho\": 0.1911, \"auroc\": 0.5989}, \"logprob_re\": {\"rho\": 0.3246, \"auroc\": 0.6678}, \"fail_reason\": \"RE rho_sj=0.2870 < 0.40 threshold; >30% samples F1=0\"}, \"hypothesis\": \"LLaMA SciERC seed=456: early cross-model multi-seed test. Verifies LLaMA NER signal pattern is reproducible across sampling seeds.\"}, \"exp_007_llama_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:50.157Z\", \"updated_at\": \"2026-05-17T02:57:58.879Z\", \"spec\": {\"description\": \"LLaMA 3.1-8B SciERC joint extraction, seed=123, cross-model robustness test\", \"hypothesis\": \"Structural consistency generalizes across model architectures (LLaMA vs Qwen)\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_seed123\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 123, \"gpu\": [\"cuda:1\"], \"backend\": \"tmux\", \"tmux_session\": \"exp007_s123\", \"account\": \"root\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed123/run.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed123/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T15:19:43.424Z\", \"metrics\": {\"verdict\": \"FAIL\", \"ner\": {\"greedy_f1\": 0.6605, \"oracle_f1\": 0.7703, \"headroom\": 0.1098, \"fleiss_kappa\": 0.4553, \"soft_jaccard\": 0.7525, \"rho_kappa_f1\": 0.2143, \"rho_sj_f1\": 0.3371, \"structural_gt_surface\": true}, \"re\": {\"greedy_f1\": 0.433, \"oracle_f1\": 0.5719, \"headroom\": 0.1389, \"fleiss_kappa\": 0.3851, \"soft_jaccard\": 0.6911, \"rho_kappa_f1\": 0.2844, \"rho_sj_f1\": 0.268, \"structural_gt_surface\": false}, \"fail_reasons\": [\"RE rho_sj=0.2680 < 0.40 threshold\", \">30% samples F1=0 (RE: 41.0%)\", \"RE structural not > surface (delta=-0.0165)\"]}, \"hypothesis\": \"LLaMA SciERC seed=123: early cross-model multi-seed test. Verifies LLaMA NER signal pattern is reproducible across sampling seeds.\"}, \"exp_008_re_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:51.386Z\", \"updated_at\": \"2026-05-17T02:57:58.166Z\", \"spec\": {\"description\": \"RE N=16 on SciERC, seed=123, seed robustness test for relation extraction\", \"hypothesis\": \"Structural consistency correlates with per-instance RE F1, robust across seeds\", \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_008_re_seed123\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": [\"cuda:3\"], \"backend\": \"tmux\", \"tmux_session\": \"exp008_rs123\", \"account\": \"root\", \"log_path\": \"output/exp_008_re_seed123/run.log\"}, \"log_path\": \"output/exp_008_re_seed123/run.log\", \"conclusion\": \"negative\", \"metrics\": {\"greedy_f1\": 0.4229, \"oracle_f1\": 0.6244, \"oracle_headroom\": 0.2015, \"fleiss_kappa_mean\": 0.3455, \"soft_jaccard_mean\": 0.6126, \"sample_f1_mean\": 0.3594, \"sample_f1_std\": 0.3793, \"sample_f1_zero_pct\": 44.1, \"structural_gt_surface\": false, \"rho_kappa_f1_full\": 0.3174, \"rho_sj_f1_full\": 0.2835, \"rho_kappa_f1_cond\": 0.0766, \"rho_sj_f1_cond\": 0.2877, \"logprob_auroc_full\": 0.6499, \"logprob_auroc_cond\": 0.5265, \"verdict\": \"FAIL\"}, \"checkpoint_path\": \"N/A\", \"completed_at\": \"2026-05-14T15:21:39.591Z\", \"hypothesis\": \"RE seed=123 multi-seed: tests reproducibility of RE signal rankings. Hypothesis: RE signals weaker than NER due to higher zero-F1 rate, but ranking should be seed-stable.\"}, \"exp_001_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:02.350Z\", \"updated_at\": \"2026-05-17T02:57:57.324Z\", \"spec\": {\"description\": \"NER N=16 on SciERC, seed=42, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency (Fleiss kappa, Soft Jaccard) correlates with per-instance NER F1 on SciERC\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 42, \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed42_v2\", \"gpu\": [\"cuda:1\"], \"pid\": \"78728\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_001_seed42_v2/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"sj_rho_full\": 0.428, \"sj_rho_cond\": 0.369, \"structural_minus_surface\": 0.147, \"conclusion_note\": \"NER seed42 robustness confirmed, structural>surface +0.147\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:34.091Z\", \"log_path\": \"output/exp_001_seed42_v2/\", \"hypothesis\": \"SciERC NER seed=42 v2: primary seed baseline under corrected pipeline. Establishes canonical signal rankings (SJ>FK>LP) for NER with gold-filtering.\"}, \"exp_001_seed123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:04.210Z\", \"updated_at\": \"2026-05-17T02:57:42.106Z\", \"spec\": {\"description\": \"NER N=16 on SciERC, seed=123, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency (Fleiss kappa, Soft Jaccard) correlates with per-instance NER F1 on SciERC (seed robustness check)\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 123, \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed123_v2\", \"gpu\": [\"cuda:2\"], \"pid\": \"78733\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_001_seed123_v2/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"sj_rho_full\": 0.424, \"sj_rho_cond\": 0.376, \"structural_minus_surface\": 0.149, \"conclusion_note\": \"NER seed123 robustness confirmed, structural>surface +0.149\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:35.076Z\", \"log_path\": \"output/exp_001_seed123_v2/\", \"hypothesis\": \"SciERC NER seed=123 v2: second seed for multi-seed validation. Establishes reproducibility of structural>surface signal ranking across random seeds.\"}, \"exp_008_re_n16_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:06.296Z\", \"updated_at\": \"2026-05-17T02:57:41.178Z\", \"spec\": {\"description\": \"RE N=16 on SciERC full set confirmation, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency correlates with per-instance RE F1 on SciERC full dataset\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 42, \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_008_re_n16_v2\", \"gpu\": [\"cuda:3\"], \"pid\": \"78737\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_008_re_n16_v2/run.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"sj_rho_full\": 0.281, \"sj_rho_cond\": 0.308, \"f1_zero_pct\": 44.3, \"conclusion_note\": \"RE N=16 v2 negative: SJ weak, 44.3% F1=0\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:35.598Z\", \"log_path\": \"output/exp_008_re_n16_v2/\", \"hypothesis\": \"RE N=16 evaluation v2: tests structural signal effectiveness on relation extraction at higher sample count. Hypothesis: SJ/FK benefit from more samples on RE task where zero-F1 rate is high.\"}, \"exp_005_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:28:14.924Z\", \"updated_at\": \"2026-05-17T02:57:38.756Z\", \"spec\": {\"description\": \"Temperature sensitivity analysis: T=0.7 vs T=1.0 across 5 signals (SJ, FK, logprob, EM, voting_conf)\", \"command\": \"python code/analyze_exp005_v2_temperature.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/mvp_pilot_004 + output/mvp_pilot_005 + output/exp_012_logprob\", \"data_count\": 551, \"model_name\": \"Qwen3-8B-SciERC-LoRA\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp_005_v2_temperature/temperature_sensitivity_report.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:28:35.949Z\", \"hypothesis\": \"Selection F1 analysis v2: compute actual selection F1 (pick best sample by each signal) vs greedy and oracle. First evidence of correlation-selection gap under corrected pipeline.\"}, \"exp_006_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:30:02.348Z\", \"updated_at\": \"2026-05-17T02:57:36.914Z\", \"spec\": {\"command\": \"python3 code/exp_006_v2_selection.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_{001_seed42,001_seed123,002_conll,008_re}_v2/\", \"data_count\": 4952, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"output/exp_006_v2/exp_006_v2_results.json\", \"log_path\": \"output/exp_006_v2_run.log\", \"completed_at\": \"2026-05-14T15:30:32.474Z\", \"metrics\": {\"NER_SciERC_s42\": {\"greedy\": 0.618, \"oracle\": 0.787, \"SJ\": 0.62, \"logprob\": 0.621, \"FK\": 0.621, \"EM\": 0.606, \"voting_conf\": 0.585, \"random\": 0.586}, \"NER_SciERC_s123\": {\"greedy\": 0.618, \"oracle\": 0.785, \"SJ\": 0.617, \"logprob\": 0.618, \"FK\": 0.621, \"EM\": 0.613, \"voting_conf\": 0.584, \"random\": 0.583}, \"NER_CoNLL\": {\"greedy\": 0.725, \"oracle\": 0.757, \"SJ\": 0.718, \"logprob\": 0.716, \"FK\": 0.717, \"EM\": 0.716, \"voting_conf\": 0.714, \"random\": 0.692}, \"RE_SciERC\": {\"greedy\": 0.403, \"oracle\": 0.631, \"SJ\": 0.397, \"logprob\": 0.41, \"FK\": 0.396, \"EM\": 0.381, \"voting_conf\": 0.408, \"random\": 0.364}}, \"hypothesis\": \"Temperature sensitivity v2: tests signal effectiveness at T=0.5,0.7,1.0,1.2. Hypothesis: structural signals are temperature-robust while LP degrades at extreme temperatures.\"}, \"exp_004_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:31:40.554Z\", \"updated_at\": \"2026-05-17T02:57:35.012Z\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/analyze_exp004_v2_re_diagnostic.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004v2_re_diagnostic/\"}, \"completed_at\": \"2026-05-14T15:32:04.966Z\", \"hypothesis\": \"N-ablation v2 (N=4,8,16,32): tests how sample count affects signal ρ and selection F1. Validates N-scaling curve for structural vs surface signals under corrected pipeline.\"}, \"exp_009_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:36:47.946Z\", \"updated_at\": \"2026-05-17T02:57:32.655Z\", \"spec\": {\"command\": \"python3 code/exp_009_v2_stratification.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2 + exp_001_seed123_v2 + exp_008_re_n16_v2\", \"data_count\": 551, \"model_name\": \"analysis\", \"seed\": 42}, \"checkpoint_path\": \"output/exp_009_v2/results.json\", \"log_path\": \"output/exp_009_v2_run.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:37:18.311Z\", \"metrics\": {\"ner_seed42_global\": {\"sj_rho\": 0.431, \"fk_rho\": 0.325, \"logprob_rho\": 0.203, \"voting_conf_rho\": 0.475, \"em_rho\": 0.292}, \"ner_seed123_global\": {\"sj_rho\": 0.422, \"fk_rho\": 0.315, \"logprob_rho\": 0.226, \"voting_conf_rho\": 0.438, \"em_rho\": 0.299}, \"re_seed42_global\": {\"sj_rho\": 0.063, \"fk_rho\": 0.226, \"logprob_rho\": 0.4, \"voting_conf_rho\": 0.22, \"em_rho\": -0.132}, \"ner_seed_stability_max_delta\": 0.037, \"independent_proxies\": [\"sent_len\", \"ent_count\", \"type_diversity\"], \"inverted_u_ner\": \"not confirmed (ρ stable across independent proxies)\", \"inverted_u_re\": \"monotonic increase with complexity, not inverted-U\"}, \"hypothesis\": \"Capability stratification v2: corrected stratification with gold-filtering and extended to NER conditional analysis. Tests which instance subpopulations drive overall signal effectiveness.\"}, \"exp_016_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:39:07.501Z\", \"updated_at\": \"2026-05-17T02:57:30.726Z\", \"spec\": {\"command\": \"python code/exp_016_v2_ensemble.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2 + exp_001_seed123_v2 + exp_008_re_n16_v2\", \"data_count\": 551, \"model_name\": \"analysis_only\", \"seed\": 42, \"checkpoint_path\": \"output/exp_016_v2/\", \"log_path\": \"/tmp/exp016v2.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:39:34.478Z\", \"metrics\": {\"ner_conditional\": {\"n\": 529, \"best_single_signal_rho\": {\"soft_jaccard\": 0.4412}, \"best_combo_rho\": {\"sj+vc_a0.55\": 0.4552}, \"ensemble_auroc\": 0.7141, \"best_single_auroc\": {\"soft_jaccard\": 0.7166}, \"selection_f1\": {\"greedy\": 0.6442, \"logprob_best\": 0.6505, \"ensemble_best\": 0.6475, \"sj_best\": 0.6471, \"oracle\": 0.8442}}, \"re_conditional\": {\"n\": 397, \"best_single_signal_rho\": {\"voting_confidence\": 0.3849}, \"best_combo_rho\": {\"logprob+vc_a0.25\": 0.3936}, \"ensemble_auroc\": 0.6916, \"best_single_auroc\": {\"voting_confidence\": 0.7023}, \"selection_f1\": {\"greedy\": 0.403, \"logprob_best\": 0.4097, \"ensemble_best\": 0.4227, \"oracle\": 0.6306}}, \"re_full\": {\"ensemble_auroc\": 0.8608, \"best_single_auroc\": {\"voting_confidence\": 0.8248}}}, \"hypothesis\": \"Bootstrap significance v2: corrected bootstrap test for NER selection F1 gap with proper gold-filtering and multiple signals. Establishes which selection improvements are statistically significant.\"}, \"exp_001_seed456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:38:55.569Z\", \"updated_at\": \"2026-05-17T02:57:23.336Z\", \"spec\": {\"hypothesis\": \"NER/RE N=16 seed=456 robustness test, third seed for 3-seed stability\", \"plan_id\": \"exp-001\", \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed456_v2\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"metrics\": {\"full_rho_kappa_f1\": 0.3383, \"full_rho_sj_f1\": 0.2988, \"cond_rho_kappa_f1\": 0.233, \"cond_rho_sj_f1\": 0.3245, \"logprob_full_rho\": 0.3405, \"logprob_full_auroc\": 0.6694, \"logprob_cond_rho\": 0.0501, \"structural_gt_surface\": false}, \"note\": \"CRITICAL: Ran with --subtask joint instead of --subtask ner. seed42/seed123 v2 used --subtask ner. Results valid for joint-mode analysis but NOT comparable for NER 3-seed protocol. Need NER-only rerun.\", \"log_path\": \"output/exp_001_seed456_v2/run.log\", \"checkpoint_path\": \"output/exp_001_seed456_v2/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T17:12:14.682Z\", \"hypothesis\": \"SciERC joint NER+RE seed=456 v2: early pipeline version. Tests multi-seed stability of signal rankings on joint extraction task.\"}, \"exp_017_llama_conll_infer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:33:23.653Z\", \"updated_at\": \"2026-05-17T02:57:21.948Z\", \"spec\": {\"hypothesis\": \"LLaMA-3.1-8B CoNLL-2003 inference: cross-model cross-dataset validation of structural consistency signals\", \"plan_id\": \"exp-017\", \"parent\": \"exp_017_llama_conll\", \"command\": \"python code/run_llama_conll_infer.py\", \"server\": \"autodl-5090\", \"data_path\": \"conll2003 test\", \"data_count\": 3453, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 42, \"n_samples\": 8, \"temperature\": 1, \"description\": \"LLaMA CoNLL-2003 NER inference N=8 (cross-model + cross-dataset validation)\"}, \"metrics\": {\"greedy_f1\": 0.9266, \"oracle_f1\": 0.9443, \"oracle_headroom\": 0.0177, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"N\": 8, \"full\": {\"SJ_rho\": 0.4314, \"FK_rho\": 0.4277, \"logprob_rho\": 0.3072, \"EM_rho\": 0.4306, \"voting_conf_rho\": 0.4256, \"SJ_AUROC\": 0.7039, \"FK_AUROC\": 0.7026, \"logprob_AUROC\": 0.761, \"EM_AUROC\": 0.7046, \"voting_conf_AUROC\": 0.7088, \"SJ_ECE\": 0.1137, \"FK_ECE\": 0.1053, \"logprob_ECE\": 0.129, \"EM_ECE\": 0.1094, \"voting_conf_ECE\": 0.0949}, \"conditional\": {\"SJ_rho\": 0.4356, \"FK_rho\": 0.431, \"logprob_rho\": 0.3282, \"EM_rho\": 0.4403, \"voting_conf_rho\": 0.3743, \"SJ_AUROC\": 0.7225, \"FK_AUROC\": 0.7208, \"logprob_AUROC\": 0.8102, \"EM_AUROC\": 0.7257, \"voting_conf_AUROC\": 0.6989, \"SJ_ECE\": 0.0829, \"FK_ECE\": 0.0796, \"logprob_ECE\": 0.0922, \"EM_ECE\": 0.0754, \"voting_conf_ECE\": 0.0784}}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/samples.jsonl\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T17:55:33.476Z\", \"notes\": \"LLaMA CoNLL-2003 NER N=8 (not N=16, cost constraint: 3453 test instances). SJ ρ=0.431 > logprob ρ=0.307 (Δ=+0.124). ρ-AUROC dissociation: logprob AUROC=0.761 > SJ AUROC=0.704. All 4 structural signals ρ>0.42 vs logprob 0.31. Directly comparable to exp_002 (Qwen CoNLL N=8) and exp_007 (LLaMA SciERC N=8).\", \"hypothesis\": \"LLaMA CoNLL N=8 baseline inference: initial cross-model test on CoNLL before scaling to N=16. Establishes LLaMA can do CoNLL NER effectively.\"}, \"exp_003_wnut17_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:32:56.415Z\", \"updated_at\": \"2026-05-17T02:57:20.068Z\", \"spec\": {\"description\": \"WNUT-17 retrain: downsample gold-empty instances to ≤25%, fine-tune Qwen3-8B, inference N=16 T=1.0 with log-probs\", \"hypothesis\": \"After removing excess empty instances, structural consistency signals (SJ) will show stronger correlation on social media NER\", \"plan_id\": \"exp-003\", \"claim\": 1, \"model_name\": \"Qwen3-8B\", \"dataset\": \"WNUT-17 (downsampled)\", \"priority\": \"P0\", \"parent\": \"exp_003_ner_wnut17\", \"command\": \"CUDA_VISIBLE_DEVICES=1 llamafactory-cli train train_config_wnut17.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/wnut17/llmfactory_train_downsampled.json\", \"data_count\": 1637, \"seed\": 42, \"pid\": 92215, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/train_wnut17.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-lora\", \"downsampling\": \"empty instances 63.8% -> 25.0%, total 3394 -> 1637\", \"metrics\": {\"train_loss\": 0.105, \"eval_loss\": 0.0836, \"epochs\": 5, \"train_time_min\": 16.37, \"train_samples_per_sec\": 8.33}, \"note\": \"D045: Training succeeded (train_loss=0.105) but inference FAIL: 54% F1=0, SJ rho=0.062 (p=0.106). WNUT-17 abandoned — model capability insufficient on social media NER. Paper reports as Claim 3 (capability boundary) evidence.\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T18:11:36.559Z\", \"hypothesis\": \"WNUT-17 NER evaluation v2: tests signal effectiveness on noisy social media text. Hypothesis: structural signals remain effective on noisy, informal text with high entity variation.\"}, \"exp_001_seed456_v2_ner\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:13:00.414Z\", \"updated_at\": \"2026-05-17T02:57:18.227Z\", \"spec\": {\"hypothesis\": \"NER N=16 seed=456 robustness test (NER-only rerun, fixing subtask mismatch from exp_001_seed456_v2)\", \"plan_id\": \"exp-001\", \"parent\": \"exp_001_seed456_v2\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed456_v2_ner\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"data/scierc/processed_data\", \"metrics\": {\"sj_rho\": 0.384, \"structural_gt_surface\": true, \"structural_surface_delta\": 0.16}, \"log_path\": \"output/exp_001_seed456_v2_ner.log\", \"checkpoint_path\": \"output/exp_001_seed456_v2_ner/\"}, \"log_path\": \"output/exp_001_seed456_v2_ner.log\", \"pid\": 96161, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T17:52:01.372Z\", \"metrics\": {\"full\": {\"SJ\": {\"rho\": 0.384, \"auroc\": 0.711}, \"FK\": {\"rho\": 0.223, \"auroc\": 0.577}, \"logprob\": {\"rho\": 0.232, \"auroc\": 0.594}, \"EM\": {\"rho\": 0.316, \"auroc\": 0.768}, \"voting_conf\": {\"rho\": 0.411, \"auroc\": 0.712}}, \"conditional\": {\"SJ\": {\"rho\": 0.349, \"auroc\": 0.699}, \"FK\": {\"rho\": 0.157, \"auroc\": 0.561}, \"logprob\": {\"rho\": 0.171, \"auroc\": 0.576}, \"EM\": {\"rho\": 0.406, \"auroc\": 0.78}, \"voting_conf\": {\"rho\": 0.346, \"auroc\": 0.694}}, \"3seed_mean_SJ_rho_full\": 0.412, \"3seed_sd_SJ_rho_full\": 0.025, \"structural_beats_surface\": true, \"verdict\": \"MARGINAL\"}, \"hypothesis\": \"SciERC NER seed=456 v2: corrected pipeline rerun with gold-filtering. Part of multi-seed validation protocol for NER signal ranking stability.\"}, \"exp_009_v2_re_rerun\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:56:31.535Z\", \"updated_at\": \"2026-05-17T02:57:16.383Z\", \"spec\": {\"command\": \"python code/exp_009_v2_re_rerun.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_008_re_n16_v2/samples.jsonl\", \"data_count\": 397, \"model_name\": \"cpu_analysis\", \"seed\": 42, \"checkpoint_source\": \"exp_008_re_n16_v2\", \"checkpoint_path\": \"output/exp_009_v2_re_rerun/results.json\", \"log_path\": \"/tmp/re_rerun.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T18:56:58.168Z\", \"hypothesis\": \"Capability stratification v2 (RE rerun): corrected stratification analysis for RE with proper gold-filtering. Fixes early pipeline bug affecting RE quartile ρ values.\"}, \"exp_007_llama_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:31:44.366Z\", \"updated_at\": \"2026-05-17T02:57:12.521Z\", \"spec\": {\"hypothesis\": \"LLaMA SciERC N=16: cross-model N-scaling validation. If SJ rho increases from N=8 (0.363) to N=16, N-scaling is model-agnostic.\", \"plan_id\": \"exp-007\", \"parent\": \"exp_007_llama_inference\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_n16\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/llama3.1-8b-scierc-merged\", \"eval_data\": \"data/scierc/processed_data\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/exp_007_llama_n16/samples.jsonl\", \"log_path\": \"output/exp_007_llama_n16.log\", \"completed_at\": \"2026-05-14T19:03:39.163Z\", \"metrics\": {\"N\": 16, \"dataset\": \"scierc\", \"subtask\": \"ner\", \"n_instances\": 551, \"n_valid\": 529, \"n_conditional\": 478, \"greedy_f1\": 0.645, \"full\": {\"SJ_rho\": 0.3791, \"FK_rho\": 0.3081, \"logprob_rho\": 0.2041, \"EM_rho\": 0.3159, \"voting_conf_rho\": 0.4515, \"SJ_AUROC\": 0.717, \"FK_AUROC\": 0.6581, \"logprob_AUROC\": 0.5656, \"EM_AUROC\": 0.7686, \"voting_conf_AUROC\": 0.7266, \"SJ_ECE\": 0.1019, \"FK_ECE\": 0.1556, \"logprob_ECE\": 0.084, \"EM_ECE\": 0.1761, \"voting_conf_ECE\": 0.1365}, \"conditional\": {\"SJ_rho\": 0.3222, \"FK_rho\": 0.2182, \"logprob_rho\": 0.1286, \"EM_rho\": 0.3563, \"voting_conf_rho\": 0.3356, \"SJ_AUROC\": 0.7014, \"FK_AUROC\": 0.6392, \"logprob_AUROC\": 0.545, \"EM_AUROC\": 0.7708, \"voting_conf_AUROC\": 0.6988, \"SJ_ECE\": 0.1466, \"FK_ECE\": 0.1853, \"logprob_ECE\": 0.1141, \"EM_ECE\": 0.1887, \"voting_conf_ECE\": 0.2634}, \"n8_vs_n16_delta_rho_full\": {\"SJ\": 0.0161, \"FK\": -0.0185, \"logprob\": 0.0214, \"EM\": 0.0007, \"voting_conf\": 0.0184}}, \"hypothesis\": \"LLaMA SciERC N=16: cross-model NER signal evaluation at higher sample count. Tests if LLaMA shows same N-scaling benefit for structural signals as Qwen.\"}, \"exp_017_llama_conll_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:19:35.318Z\", \"updated_at\": \"2026-05-17T02:56:57.283Z\", \"spec\": {\"hypothesis\": \"LLaMA CoNLL N=16: complete the 2x2 matrix (model x dataset x N). If SJ N-scaling holds for LLaMA on CoNLL, the finding is fully cross-model cross-dataset.\", \"plan_id\": \"exp-017\", \"parent\": \"exp_017_llama_conll_infer\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"data_count\": 3453, \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_017_llama_conll_n16\", \"data_path\": \"data/conll2003\", \"pid\": 106997, \"n_samples\": 16, \"temperature\": 1, \"checkpoint_source\": \"checkpoints/llama3.1-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16/all_signals_report.json\"}, \"metrics\": {\"greedy_f1\": 0.9243, \"oracle_f1\": 0.9487, \"oracle_headroom\": 0.0244, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4642, \"SJ_AUROC\": 0.7391, \"SJ_ECE\": 0.1131, \"FK_rho\": 0.4566, \"FK_AUROC\": 0.736, \"FK_ECE\": 0.1071, \"logprob_rho\": 0.3058, \"logprob_AUROC\": 0.7594, \"logprob_ECE\": 0.1288, \"EM_rho\": 0.4613, \"EM_AUROC\": 0.7391, \"EM_ECE\": 0.1084, \"voting_conf_rho\": 0.4554, \"voting_conf_AUROC\": 0.7406, \"voting_conf_ECE\": 0.0844}, \"conditional\": {\"SJ_rho\": 0.4597, \"SJ_AUROC\": 0.7565, \"SJ_ECE\": 0.0846, \"FK_rho\": 0.4515, \"FK_AUROC\": 0.753, \"FK_ECE\": 0.0813, \"logprob_rho\": 0.3193, \"logprob_AUROC\": 0.8023, \"logprob_ECE\": 0.0921, \"EM_rho\": 0.4618, \"EM_AUROC\": 0.7589, \"EM_ECE\": 0.0757, \"voting_conf_rho\": 0.3978, \"voting_conf_AUROC\": 0.7287, \"voting_conf_ECE\": 0.0742}, \"best_of_n\": {\"greedy\": 0.9243, \"random_avg\": 0.9213, \"sj_best\": 0.9259, \"logprob_best\": 0.925, \"voting_conf_best\": 0.9268, \"oracle\": 0.9487}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0328, \"full_FK_rho_delta\": 0.0289, \"full_logprob_rho_delta\": -0.0014, \"full_EM_rho_delta\": 0.0307, \"full_voting_conf_rho_delta\": 0.0298, \"cond_SJ_rho_delta\": 0.0241, \"cond_FK_rho_delta\": 0.0205, \"cond_logprob_rho_delta\": -0.0089, \"cond_EM_rho_delta\": 0.0215, \"cond_voting_conf_rho_delta\": 0.0235}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T19:45:16.265Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=42 (original): cross-model validation on CoNLL. First evidence that structural>surface ranking generalizes from Qwen to LLaMA model family.\"}, \"exp_015_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:34:23.336Z\", \"updated_at\": \"2026-05-17T02:56:55.830Z\", \"spec\": {\"command\": \"python code/analyze_exp015_v2_metrics.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/ (10 datasets)\", \"data_count\": 9148, \"model_name\": \"Qwen3-8B + LLaMA (multi-model)\", \"seed\": \"42,123,456 (multi-seed)\", \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"/tmp/exp015_v2.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:34:56.741Z\", \"metrics\": {\"scierc_ner_avg\": {\"sj_auroc\": 0.7394, \"fk_auroc\": 0.6172, \"em_auroc\": 0.7873, \"voting_auroc\": 0.7367, \"logprob_auroc\": 0.5918}, \"scierc_re_avg\": {\"sj_auroc\": 0.6746, \"fk_auroc\": 0.5939, \"em_auroc\": 0.715, \"voting_auroc\": 0.7234, \"logprob_auroc\": 0.5849}}, \"hypothesis\": \"Metrics expansion v2: corrected evaluation with proper conditional filtering. Updates exp_015 with gold-filtered pipeline to fix RE conditional ρ values that used wrong filter criterion.\"}, \"exp_001_n16_seed456\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T12:10:30.350Z\", \"updated_at\": \"2026-05-17T02:56:53.526Z\", \"completed_at\": \"2026-05-14T12:28:38.721Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"success\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.6577, \"oracle_f1\": 0.8129, \"headroom\": 0.1553, \"rho_sj_full\": 0.3297, \"rho_fk_full\": 0.2578, \"rho_logprob_full\": 0.2866, \"rho_sj_cond\": 0.3394, \"rho_fk_cond\": 0.2721, \"rho_logprob_cond\": 0.2567, \"sj_beats_fk\": true, \"rho_advantage\": 0.0719}, \"re\": {\"greedy_f1\": 0.4312, \"oracle_f1\": 0.6737, \"headroom\": 0.2425, \"rho_sj_full\": 0.285, \"rho_fk_full\": 0.2372, \"rho_logprob_full\": 0.2626, \"rho_sj_cond\": 0.3525, \"rho_fk_cond\": 0.2614, \"rho_logprob_cond\": 0.1927, \"sj_beats_fk\": true, \"rho_advantage\": 0.0478}, \"verdict\": \"FAIL\"}}}, \"spec\": {\"hypothesis\": \"N=16 seed456 multi-seed robustness verification for SciERC NER+RE\", \"plan_id\": \"exp-001\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"seed\": 456, \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --output_dir output/exp001_n16_seed456 --collect_logprobs\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"174595\", \"log_path\": \"output/exp001_n16_seed456_run.log\", \"tmux_session\": \"exp_001_n16_seed456\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (inference-only)\", \"metrics\": {\"instance_count\": 551, \"n_valid\": 529, \"n_gold_empty\": 22, \"parse_rate\": 1, \"ner_greedy_f1\": 0.6617, \"ner_oracle_f1\": 0.8075, \"re_greedy_f1\": 0.4215, \"re_oracle_f1\": 0.4748, \"rho_sj_ner\": 0.4098, \"rho_fk_ner\": 0.2723, \"rho_vc_ner\": 0.4449, \"rho_em_ner\": 0.3363, \"rho_lp_ner\": 0.2415, \"rho_sj_re\": 0.2835, \"rho_fk_re\": 0.2929, \"auroc_sj_ner\": 0.6823, \"auroc_fk_ner\": 0.6179, \"auroc_vc_ner\": 0.6981, \"auroc_em_ner\": 0.649, \"auroc_lp_ner\": 0.5885, \"rho_note\": \"CORRECTED 2026-05-15: old values (rho_fk=0.3448,rho_sj=0.4134) included 22 gold-empty instances. Now uses gold-filtered pipeline (n=529).\"}, \"log_path\": \"output/exp001_n16_seed456_run.log\", \"hypothesis\": \"SciERC N=16 seed=456: early multi-seed validation of structural signal rankings at N=16 sample count. Establishes seed stability for SJ/FK/VC/EM ordering.\"}, \"exp_011_ood_scierc_to_conll\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:36:07.210Z\", \"updated_at\": \"2026-05-17T02:56:29.417Z\", \"spec\": {\"hypothesis\": \"SCS structural signals remain effective under domain shift (SciERC model on CoNLL data)\", \"plan_id\": \"exp-011\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"data_path\": \"data/conll2003\", \"seed\": 42, \"pid\": 179761, \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset conll2003 --data_dir data/conll2003 --subtask ner --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 42 --collect_logprobs --output_dir output/exp_011_ood_scierc_to_conll\", \"data_count\": 3500}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/exp_011_ood_scierc_to_conll/samples.jsonl\", \"log_path\": \"output/exp_011_ood_scierc_to_conll/report.json\", \"completed_at\": \"2026-05-15T11:47:47.953Z\", \"metrics\": {\"greedy_ner_f1\": 0.522, \"rho_vc\": 0.469, \"rho_sj\": 0.378, \"rho_em\": 0.3, \"rho_fk\": 0.285, \"rho_lp\": 0.246}, \"hypothesis\": \"Out-of-domain transfer: SciERC-trained model on CoNLL data. Tests if confidence signals work under partial schema overlap (SciERC has Organization/Person which overlap with CoNLL ORG/PER). Complement to exp_011_ood_conll_to_scierc.\"}, \"exp_qwen3_4b_scierc_finetune_v4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:26:25.512Z\", \"updated_at\": \"2026-05-17T02:56:24.418Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_scierc_4b.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"227123\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v4.log\", \"submitted_at\": \"2026-05-15T19:26:31.444Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"wall_clock_seconds\": 1668.8, \"gpu_hours\": 0.46}, \"conclusion\": \"success\", \"metrics\": {\"total_steps\": 585, \"completed_steps\": 585, \"best_checkpoint\": \"checkpoint-400\", \"best_eval_loss\": 0.0898, \"epochs\": 5}, \"checkpoint_path\": \"checkpoints/qwen3-4b-scierc-merged/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v4.log\", \"completed_at\": \"2026-05-15T19:54:20.255Z\", \"hypothesis\": \"Qwen3-4B SciERC LoRA fine-tune v4: training the smaller 4B model to complete the 2x2 scale matrix (4B×SciERC cell). Validates that fine-tuning convergence patterns hold across model scales.\"}, \"exp_011_ood_conll_to_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:36:08.325Z\", \"updated_at\": \"2026-05-17T02:56:14.242Z\", \"spec\": {\"hypothesis\": \"SCS structural signals remain effective under domain shift (CoNLL model on SciERC data, joint NER+RE)\", \"plan_id\": \"exp-011\", \"model_name\": \"qwen3-8b-conll2003-merged\", \"data_path\": \"data/scierc/processed_data\", \"seed\": 42, \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": 181723, \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --dataset scierc --data_dir data/scierc/processed_data --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 42 --collect_logprobs --output_dir output/exp_011_ood_conll_to_scierc\", \"data_count\": 551}, \"conclusion\": \"negative\", \"checkpoint_path\": \"output/exp_011_ood_conll_to_scierc/samples.jsonl\", \"log_path\": \"output/exp_011_ood_conll_to_scierc/report.json\", \"completed_at\": \"2026-05-15T11:50:21.969Z\", \"metrics\": {\"greedy_ner_f1\": 0.009, \"greedy_re_f1\": 0.001, \"avg_structural_rho\": -0.05, \"verdict\": \"FAIL\", \"reason\": \"schema_incompatibility\", \"direction\": \"CoNLL_model_to_SciERC_data\", \"sample_f1_pct_zero_ner\": 98.06, \"rho_sj_ner\": -0.186, \"rho_fk_ner\": -0.069, \"note\": \"Schema incompatibility (CoNLL PER/ORG/LOC/MISC vs SciERC Task/Method/Material) causes catastrophic failure. Cannot evaluate confidence signals.\"}, \"hypothesis\": \"Out-of-domain transfer test: CoNLL-trained model on SciERC data. Tests if confidence signals retain correlation with quality under severe schema mismatch (CoNLL PER/ORG/LOC/MISC vs SciERC Task/Method/Material).\"}, \"exp_freeform_seed789_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:24:26.805Z\", \"updated_at\": \"2026-05-17T02:56:11.818Z\", \"spec\": {\"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_seed789_v3.log\", \"checkpoint_path\": \"results/exp_freeform_ablation_seed789/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:30:51.048Z\", \"metrics\": {\"n_instances\": 551, \"n_samples\": 8, \"parse_rate_pct\": 100, \"elapsed_seconds\": 229.7, \"freeform_ner_selection_gap\": 0.0028, \"freeform_re_selection_gap\": 0.0219, \"freeform_lp_std\": 0.0183, \"freeform_lp_range\": 0.054908, \"freeform_tied_pct\": 59, \"re_lp_flip_positive\": true, \"variance_ratio_std\": 0.89, \"variance_ratio_range\": 0.88}, \"hypothesis\": \"Free-form SciERC seed=789 v3 (bugfix rerun): corrected version of free-form inference after fixing parsing/generation issues in v1/v2. Provides clean data point for 4-seed free-form analysis.\"}, \"exp_freeform_seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:38:29.851Z\", \"updated_at\": \"2026-05-17T02:56:09.888Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python run_freeform_inference.py --seed 789 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed789\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"216722\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_seed789.log\", \"submitted_at\": \"2026-05-15T18:58:46.406Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 92.2, \"gpu_hours\": 0.03}, \"notes\": \"Rerun with fixed seed-passing code on cuda:3. Original run was killed for GPU reallocation. Parse rate 100%, 227.5s elapsed. LP compression confirmed: tied_pct=59.0% (vs constrained 59.7%), variance_ratio=0.89x.\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:00:18.576Z\", \"metrics\": {\"inference\": {\"n_instances\": 551, \"n_samples\": 8, \"total_samples\": 4408, \"total_parsed\": 4408, \"parse_rate_pct\": 100, \"elapsed_seconds\": 227.5}, \"freeform\": {\"selection_ner\": {\"greedy\": 0.6205, \"selected\": 0.6232, \"gap\": 0.0027}, \"selection_re\": {\"greedy\": 0.2909, \"selected\": 0.31, \"gap\": 0.0191}, \"logprob_variance\": {\"mean_std\": 0.0183, \"mean_range\": 0.054908, \"tied_pct\": 59}, \"qe_ner\": {\"n\": 529, \"SJ\": {\"rho\": 0.393995, \"auroc\": 0.734474}, \"FK\": {\"rho\": 0.312292, \"auroc\": 0.794384}, \"LP\": {\"rho\": 0.247096, \"auroc\": 0.677824}, \"EM\": {\"rho\": 0.320383, \"auroc\": 0.527033}, \"VC\": {\"rho\": 0.420625, \"auroc\": 0.768111}}, \"qe_re\": {\"n\": 397, \"SJ\": {\"rho\": 0.201746, \"auroc\": 0.574388}, \"FK\": {\"rho\": 0.2202, \"auroc\": 0.633014}, \"LP\": {\"rho\": 0.295765, \"auroc\": 0.687067}, \"EM\": {\"rho\": 0.103633, \"auroc\": 0.474737}, \"VC\": {\"rho\": 0.306868, \"auroc\": 0.642197}}}, \"constrained_ref\": {\"selection_ner\": {\"greedy\": 0.6182, \"selected\": 0.6241, \"gap\": 0.0059}, \"selection_re\": {\"greedy\": 0.2913, \"selected\": 0.2845, \"gap\": -0.0068}, \"logprob_variance\": {\"mean_std\": 0.020589, \"mean_range\": 0.062305, \"tied_pct\": 59.7}}, \"comparison\": {\"variance_ratio_std\": 0.89, \"variance_ratio_range\": 0.88, \"tied_reduction_pp\": 0.7}}, \"hypothesis\": \"Free-form SciERC seed=789: multi-seed replication of free-form ablation. Validates LP compression persistence and structural signal robustness across sampling seeds under unconstrained generation.\"}, \"exp_freeform_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:14:48.842Z\", \"updated_at\": \"2026-05-17T02:56:09.256Z\", \"spec\": {\"hypothesis\": \"Multi-seed free-form ablation (seed=456): verify RE LP flip and NER gap stability\", \"command\": \"python run_freeform_inference.py --seed 456 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed456\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"gpu\": \"cuda:2\", \"tmux_session\": \"exp_freeform_seed456\", \"log_path\": \"results/exp_freeform_ablation_seed456/run_summary.json\", \"checkpoint_path\": \"results/exp_freeform_ablation_seed456\"}, \"metrics\": {\"inference\": {\"n_instances\": 551, \"n_samples\": 8, \"total_samples\": 4408, \"total_parsed\": 4407, \"parse_rate_pct\": 99.98, \"elapsed_seconds\": 232.4}, \"freeform\": {\"selection_ner\": {\"greedy\": 0.6198, \"selected\": 0.6205, \"gap\": 0.0007}, \"selection_re\": {\"greedy\": 0.2908, \"selected\": 0.3108, \"gap\": 0.02}, \"logprob_variance\": {\"mean_std\": 0.018631, \"mean_range\": 0.056792, \"tied_pct\": 58.4}, \"qe_ner\": {\"n\": 529, \"SJ\": {\"rho\": 0.378498, \"auroc\": 0.707769}, \"FK\": {\"rho\": 0.286163, \"auroc\": 0.754779}, \"LP\": {\"rho\": 0.227089, \"auroc\": 0.672081}, \"EM\": {\"rho\": 0.319997, \"auroc\": 0.47789}, \"VC\": {\"rho\": 0.416853, \"auroc\": 0.756543}}, \"qe_re\": {\"n\": 397, \"SJ\": {\"rho\": 0.211331, \"auroc\": 0.572335}, \"FK\": {\"rho\": 0.259074, \"auroc\": 0.652998}, \"LP\": {\"rho\": 0.306382, \"auroc\": 0.70134}, \"EM\": {\"rho\": 0.1043, \"auroc\": 0.461641}, \"VC\": {\"rho\": 0.301507, \"auroc\": 0.628873}}}, \"constrained_ref\": {\"selection_ner\": {\"greedy\": 0.6182, \"selected\": 0.6241, \"gap\": 0.0059}, \"selection_re\": {\"greedy\": 0.2913, \"selected\": 0.2845, \"gap\": -0.0068}, \"logprob_variance\": {\"mean_std\": 0.020589, \"mean_range\": 0.062305, \"tied_pct\": 59.7}}, \"comparison\": {\"variance_ratio_std\": 0.9, \"variance_ratio_range\": 0.91, \"tied_reduction_pp\": 1.3}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:12:29.413Z\", \"hypothesis\": \"Free-form SciERC seed=456: multi-seed replication of free-form ablation. Validates LP compression persistence and structural signal robustness across sampling seeds under unconstrained generation.\"}, \"exp_freeform_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:14:47.765Z\", \"updated_at\": \"2026-05-17T02:56:06.903Z\", \"spec\": {\"hypothesis\": \"Multi-seed free-form ablation (seed=123): verify RE LP flip and NER gap stability\", \"command\": \"python run_freeform_inference.py --seed 123 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed123\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": \"cuda:1\", \"tmux_session\": \"exp_freeform_seed123\", \"log_path\": \"results/exp_freeform_ablation_seed123/run_summary.json\", \"checkpoint_path\": \"results/exp_freeform_ablation_seed123\"}, \"metrics\": {\"inference\": {\"n_instances\": 551, \"n_samples\": 8, \"total_samples\": 4408, \"total_parsed\": 4406, \"parse_rate_pct\": 99.95, \"elapsed_seconds\": 228.1}, \"freeform\": {\"selection_ner\": {\"greedy\": 0.6194, \"selected\": 0.6222, \"gap\": 0.0028}, \"selection_re\": {\"greedy\": 0.2874, \"selected\": 0.305, \"gap\": 0.0176}, \"logprob_variance\": {\"mean_std\": 0.019881, \"mean_range\": 0.059864, \"tied_pct\": 57.7}, \"qe_ner\": {\"n\": 529, \"SJ\": {\"rho\": 0.384214, \"auroc\": 0.748728}, \"FK\": {\"rho\": 0.323956, \"auroc\": 0.766039}, \"logprob\": {\"rho\": 0.217297, \"auroc\": 0.701657}, \"EM\": {\"rho\": 0.326887, \"auroc\": 0.52533}, \"voting_conf\": {\"rho\": 0.407893, \"auroc\": 0.799676}}, \"qe_re\": {\"n\": 397, \"SJ\": {\"rho\": 0.272776, \"auroc\": 0.614056}, \"FK\": {\"rho\": 0.314429, \"auroc\": 0.678534}, \"logprob\": {\"rho\": 0.309673, \"auroc\": 0.70414}, \"EM\": {\"rho\": 0.137216, \"auroc\": 0.487342}, \"voting_conf\": {\"rho\": 0.316667, \"auroc\": 0.647442}}}, \"constrained_ref\": {\"selection_ner\": {\"greedy\": 0.6182, \"selected\": 0.6241, \"gap\": 0.0059}, \"selection_re\": {\"greedy\": 0.2913, \"selected\": 0.2845, \"gap\": -0.0068}}, \"comparison\": {\"variance_ratio_std\": 0.97, \"variance_ratio_range\": 0.96, \"tied_reduction_pp\": 2}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:29:48.939Z\", \"hypothesis\": \"Free-form SciERC seed=123: multi-seed replication of free-form ablation. Validates LP compression persistence and structural signal robustness across sampling seeds under unconstrained generation.\"}, \"exp_009_capability_stratification\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:59:24.201Z\", \"updated_at\": \"2026-05-17T02:56:02.685Z\", \"spec\": {\"command\": \"python code/exp009_stratification_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp001_n16_seed42 + output/exp008_re_n16 + output/exp002_conll2003\", \"data_count\": 4555, \"model_name\": \"analysis_only\", \"seed\": 42}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/exp009_stratification_results.json\", \"log_path\": \"/tmp/exp009.log\", \"completed_at\": \"2026-05-14T14:59:46.463Z\", \"metrics\": {\"scierc_ner\": {\"n\": 551, \"sj_rho_overall\": 0.398, \"by_greedy_f1\": {\"hard_0_25_sj_rho\": 0.159, \"med_low_sj_rho\": 0.139, \"med_high_sj_rho\": 0.09, \"easy_sj_rho\": 0.23}, \"by_sent_len\": {\"Q1_sj_rho\": 0.461, \"Q2_sj_rho\": 0.401, \"Q3_sj_rho\": 0.296, \"Q4_sj_rho\": 0.382}, \"by_ent_count\": {\"0_sj_rho\": 0.689, \"1_2_sj_rho\": 0.415, \"3_5_sj_rho\": 0.353, \"6plus_sj_rho\": 0.547}}, \"scierc_re\": {\"n\": 551, \"by_greedy_f1\": {\"hard_0_25_sj_rho\": -0.043, \"easy_sj_rho\": 0.21}, \"by_sent_len\": {\"Q1_sj_rho\": 0.447, \"Q4_sj_rho\": 0.54}, \"by_rel_count\": {\"0_sj_rho\": 0.62, \"1_2_sj_rho\": 0.275, \"6plus_sj_rho\": 0.527}}, \"conll_ner\": {\"n\": 3453, \"by_sent_len\": {\"Q1_sj_rho\": 0.334, \"Q3_sj_rho\": 0.518}}, \"proxy_independence\": {\"scierc_ner_f1_vs_slen\": -0.021, \"scierc_ner_f1_vs_ecnt\": 0.007, \"scierc_re_f1_vs_slen\": -0.147}}, \"notes\": \"Registry metrics are PRE-gold-filter (n=551). Paper uses exp_009_v2_re_rerun (gold-filtered n=397): RE Q1_sj_rho=0.110, Q4_sj_rho=0.473. Registry values (Q1=0.447, Q4=0.540) are SUPERSEDED.\", \"hypothesis\": \"Capability stratification analysis: test if SJ signal effectiveness varies with instance difficulty (greedy F1 quartiles), sentence length, and entity/relation count. Identifies which instance subpopulations benefit most from structural consistency signals.\"}, \"exp_023_lora_rank8\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:29:59.501Z\", \"updated_at\": \"2026-05-17T02:55:50.540Z\", \"spec\": {\"hypothesis\": \"LoRA rank=8 ablation: does reducing rank from 32 to 8 significantly affect correlation-selection patterns?\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/llmfactory_train.json\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_002_v2\", \"method\": \"LoRA r=8 alpha=16, 5 epochs, batch=2 grad_accum=8 gradient_checkpointing=true\", \"gpu\": \"cuda:2\", \"pid\": 288382, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp023_rank8_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora-rank8\", \"command\": \"CUDA_VISIBLE_DEVICES=2 llamafactory-cli train train_config_rank8.yaml\", \"trainable_params\": \"21.8M\", \"total_steps\": 585, \"estimated_runtime\": \"26min\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.1018, \"eval_loss\": 0.0776, \"train_runtime\": \"28m45s\", \"ner_full\": {\"n\": 529, \"greedy_f1\": 0.6397, \"oracle_f1\": 0.7998, \"oracle_headroom\": 0.1601, \"degeneracy_rate\": 0.072, \"SJ_rho\": 0.3649, \"FK_rho\": 0.2838, \"VC_rho\": 0.394, \"EM_rho\": 0.2562, \"LP_rho\": 0.2105, \"SJ_auroc\": 0.689, \"FK_auroc\": 0.6002, \"VC_auroc\": 0.6886, \"EM_auroc\": 0.7265, \"LP_auroc\": 0.6054, \"sel_SJ\": 0.6306, \"sel_FK\": 0.6265, \"sel_VC\": 0.5919, \"sel_EM\": 0.6073, \"sel_LP\": 0.635}, \"ner_cond\": {\"n\": 477, \"SJ_rho\": 0.3056, \"FK_rho\": 0.1452, \"VC_rho\": 0.3191, \"EM_rho\": 0.3558, \"LP_rho\": 0.169}, \"re_full\": {\"n\": 397, \"greedy_f1\": 0.3712, \"oracle_f1\": 0.609, \"oracle_headroom\": 0.2378, \"degeneracy_rate\": 0.217, \"SJ_rho\": 0.2244, \"FK_rho\": 0.3448, \"VC_rho\": 0.3617, \"EM_rho\": 0.068, \"LP_rho\": 0.2737, \"SJ_auroc\": 0.7092, \"FK_auroc\": 0.6469, \"VC_auroc\": 0.7533, \"EM_auroc\": 0.7306, \"LP_auroc\": 0.6325, \"sel_SJ\": 0.3584, \"sel_FK\": 0.3498, \"sel_VC\": 0.3715, \"sel_EM\": 0.3291, \"sel_LP\": 0.3606}, \"re_cond\": {\"n\": 242, \"SJ_rho\": 0.3601, \"FK_rho\": 0.2343, \"VC_rho\": 0.3703, \"EM_rho\": 0.4613, \"LP_rho\": 0.1809}}, \"completed_at\": \"2026-05-16T11:22:34.576Z\", \"hypothesis\": \"LoRA rank=8 ablation on SciERC: test if reduced model capacity (rank 8 vs 32) changes signal effectiveness ranking or correlation-selection gap pattern. Verifies findings are not rank-specific artifacts.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_022_seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:08:27.375Z\", \"updated_at\": \"2026-05-17T02:55:49.870Z\", \"hypothesis\": \"3rd seed SciERC inference (seed=789) with ft_002_v2 (Qwen3-8B). N=8, T=1.0, joint NER+RE, logprobs collected. Complements seed42 (exp_012_rerun_1024) and seed123/456 for multi-seed analysis.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 789 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_022_seed789/\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-8B (qwen3-8b-scierc-merged-v2)\", \"seed\": 789, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_022_seed789/run.log\", \"gpu\": \"cuda:0\", \"pid\": 286743, \"account\": \"root\", \"backend\": \"tmux\", \"tmux_session\": \"exp_022_seed789\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T14:25:17.461Z\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_025_n32\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T13:38:26.420Z\", \"updated_at\": \"2026-05-17T02:55:46.212Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_025_n32/run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T14:25:39.849Z\", \"metrics\": {\"n_samples\": 32, \"degeneracy_pct\": 4, \"lp_range\": 0.0781, \"oracle_f1\": 0.8412, \"greedy_f1\": 0.6615, \"oracle_gap\": 0.1797, \"selection_f1_lp_delta\": 0.54, \"selection_f1_sj_delta\": 0.16, \"selection_f1_fk_delta\": 0.6, \"selection_f1_em_delta\": 0.68, \"selection_f1_vc_delta\": -5.21, \"best_signal\": \"EM\", \"best_delta\": 0.68, \"metric_space\": \"micro_f1_filtered_529inst\", \"note\": \"corrected via n_ablation_fixed.py, greedy from inst['greedy'] field\"}, \"hypothesis\": \"N=32 sample ablation on SciERC: test if increasing samples from 8→32 reduces degeneracy and improves selection F1, particularly for structural signals. Validates whether sample count is the bottleneck for signal effectiveness.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_021_fewnerd_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T16:33:44.079Z\", \"updated_at\": \"2026-05-17T02:55:45.560Z\", \"hypothesis\": \"Full Few-NERD LoRA fine-tune (rank=32, α=64, 3 epochs) on SUPERVISED coarse 8-type NER (131k train). 4-GPU DDP on autodl-5090. Post-training: N=8 inference on full test set, T=1.0, seed=42, collect logprobs for SCS metrics.\", \"spec\": {\"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"gpu_count\": 4, \"training_mode\": \"DDP\", \"checkpoint_path\": \"output/exp_021_fewnerd_full/checkpoint-6177\", \"log_path\": \"output/exp_021_inference/\"}, \"conclusion\": \"success\", \"metrics\": {\"total_steps\": 6177, \"train_loss\": 0.048, \"eval_loss\": 0.0275, \"train_runtime\": \"3h57m\", \"epochs\": 3, \"final_checkpoint\": \"output/exp_021_fewnerd_full/checkpoint-6177\", \"adapter_path\": \"output/exp_021_fewnerd_full/adapter_model.safetensors\", \"inference_instances\": 37648, \"inference_filtered\": 32565, \"inference_n_samples\": 8, \"greedy_macro_f1\": 0.7478, \"oracle_macro_f1\": 0.8719, \"headroom\": 0.124, \"zero_f1_rate\": 0.119, \"degeneracy_rate\": 0.101, \"lp_within_range_mean\": 0.0879, \"lp_within_range_median\": 0.0662, \"lp_global_rho\": 0.4215, \"lp_cond_rho\": 0.4225, \"sj_global_rho\": 0.3002, \"sj_cond_rho\": 0.2937, \"fk_global_rho\": 0.3132, \"fk_cond_rho\": 0.3093, \"em_global_rho\": 0.2871, \"em_cond_rho\": 0.271, \"vc_global_rho\": 0.3858, \"vc_cond_rho\": 0.3234, \"lp_selection_delta_pp\": 1.36, \"vc_selection_delta_pp\": -1.79, \"sj_selection_delta_pp\": -2.14, \"fk_selection_delta_pp\": -2.26, \"em_selection_delta_pp\": -3.85, \"lp_bootstrap_ci_95_pp\": [1.18, 1.53], \"lp_sample_auroc\": 0.5782, \"vc_sample_auroc\": 0.5354, \"fk_sample_auroc\": 0.521, \"sj_sample_auroc\": 0.5197, \"em_sample_auroc\": 0.5137, \"scenario\": \"A_partial\", \"note\": \"Full analysis (gold-filtered n=32565). Prior simplified analysis used unfiltered data with different metrics.\"}, \"completed_at\": \"2026-05-16T22:04:16.683Z\", \"parent\": \"exp_020_fewnerd_smoke\"}, \"exp_015_metrics_expansion\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:47:36.569Z\", \"updated_at\": \"2026-05-17T02:55:35.391Z\", \"spec\": {\"hypothesis\": \"Comprehensive evaluation of all 5 confidence signals with extended metrics\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"exp_012_logprob_baseline\", \"method\": \"CPU-only analysis: 6 metrics x 5 signals x 2 subtasks (NER+RE)\", \"command\": \"python code/analyze_exp015_metrics_expansion.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp015_metrics_expansion\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:22:32.661Z\", \"metrics\": {\"data_source\": \"exp_012_logprob/samples_with_logprobs.jsonl\", \"config\": \"N=8, T=1.0, seed=42, model=qwen3-8b-scierc-merged-v2\", \"ner\": {\"n_valid\": 529, \"n_cond\": 501, \"voting_rho_full\": 0.5018, \"voting_rho_cond\": 0.4497, \"voting_auroc\": 0.7279, \"voting_tau\": 0.3766, \"sj_rho_full\": 0.3565, \"sj_rho_cond\": 0.412, \"sj_auroc\": 0.6656, \"sj_tau\": 0.2658, \"em_rho_full\": 0.2566, \"em_rho_cond\": 0.3427, \"em_auroc\": 0.623, \"em_tau\": 0.1924, \"fk_rho_full\": 0.2651, \"fk_rho_cond\": 0.306, \"fk_auroc\": 0.6243, \"fk_tau\": 0.2027, \"logprob_rho_full\": 0.1396, \"logprob_rho_cond\": 0.1627, \"logprob_auroc\": 0.5585, \"logprob_tau\": 0.1006}, \"re\": {\"n_valid\": 397, \"n_cond\": 296, \"voting_rho_full\": 0.4217, \"voting_rho_cond\": 0.463, \"voting_auroc\": 0.7162, \"voting_tau\": 0.327, \"sj_rho_full\": 0.2112, \"sj_rho_cond\": 0.3683, \"sj_auroc\": 0.5816, \"sj_tau\": 0.1619, \"em_rho_full\": 0.1002, \"em_rho_cond\": 0.3607, \"em_auroc\": 0.5036, \"em_tau\": 0.0839, \"fk_rho_full\": 0.2528, \"fk_rho_cond\": 0.3168, \"fk_auroc\": 0.6308, \"fk_tau\": 0.1967, \"logprob_rho_full\": 0.2467, \"logprob_rho_cond\": 0.1457, \"logprob_auroc\": 0.6354, \"logprob_tau\": 0.1808}, \"diagnosis\": \"Unified 5-signal evaluation on single data source. Voting leads NER full (ρ=0.502), SJ retains strength in NER cond (ρ=0.412). All structural signals beat logprob on NER. RE: voting leads both full and cond.\"}, \"notes\": \"RE logprob_rho_cond=0.1457 uses WRONG conditional filter (any sample F1>0, n=331). Correct value: 0.0112 from exp_012_rerun_1024 (greedy_f1>0, n=238). This entry's RE cond values are DEPRECATED.\", \"hypothesis\": \"Unified 5-signal evaluation (SJ/FK/EM/VC/LP) on single canonical data source (exp_012 logprobs). Establishes complete signal ranking with ρ, AUROC, and τ metrics for both NER and RE under consistent conditions.\"}, \"exp_020_fewnerd_smoke\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:29:25.272Z\", \"updated_at\": \"2026-05-16T16:33:59.109Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/ft_fewnerd_smoke\", \"log_path\": \"checkpoints/fewnerd_train.log\"}, \"hypothesis\": \"1-epoch LoRA (r16) fine-tune Qwen3-8B on Few-NERD INTRA coarse 8-type (131k train), then N=8 T=1.0 pilot inference on 200 test instances. Re-started training 2026-05-16 18:29 CST on cuda:1, PID 288683. ETA ~22:55 CST.\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.031, \"total_steps\": 8236, \"training_time\": \"5h54m\", \"pilot_greedy_f1\": 0.8037, \"pilot_instances\": 200, \"merged_model_path\": \"checkpoints/qwen3-8b-fewnerd-merged\"}, \"completed_at\": \"2026-05-16T16:33:59.109Z\"}, \"exp_vc_lp_cascade_selection\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:44:02.658Z\", \"updated_at\": \"2026-05-16T06:31:26.755Z\", \"hypothesis\": \"VC-filtered LP selection cascade: test if combining VC (pre-filter) + LP (rank) improves selection F1 over single-signal selection. Addresses SF3 reviewer suggestion. Pure analysis on existing data.\", \"conclusion\": \"killed\", \"spec\": {\"command\": \"N/A - cancelled before execution\", \"server\": \"N/A\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"completed_at\": \"2026-05-16T06:31:26.755Z\"}, \"exp_tacred_re_benchmark\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:43:59.002Z\", \"updated_at\": \"2026-05-16T06:31:25.273Z\", \"hypothesis\": \"TACRED RE benchmark: replicate SciERC RE experiment flow on second RE dataset. Verify correlation-selection gap generalizes beyond SciERC. D104 highest priority — addresses R11 MF1 consensus weakness.\", \"conclusion\": \"killed\", \"spec\": {\"command\": \"N/A - cancelled before execution\", \"server\": \"N/A\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"completed_at\": \"2026-05-16T06:31:25.273Z\"}, \"exp_vc_quartile_analysis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:48:35.263Z\", \"updated_at\": \"2026-05-16T05:00:36.736Z\", \"hypothesis\": \"VC quartile stratification: split instances by VC score into Q1-Q4, compute LP selection F1 per quartile. Test if LP selection ability recovers in high-VC instances. Addresses SF3.\", \"spec\": {\"command\": \"python vc_quartile_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_rerun_1024/samples.jsonl + output/exp_002_conll_n8_seed42/samples.jsonl\", \"data_count\": 3682, \"model_name\": \"analysis_only (Qwen3-8B data)\", \"seed\": 42}, \"conclusion\": \"success\", \"checkpoint_path\": \"artifacts/vc_quartile_analysis/results.json\", \"log_path\": \"artifacts/vc_quartile_analysis/report.md\", \"completed_at\": \"2026-05-16T05:00:30.439Z\", \"metrics\": {\"scierc_ner\": {\"Q1_lp_delta\": 0.016, \"Q2_lp_delta\": -0.006, \"Q3_lp_delta\": 0.02, \"Q4_lp_delta\": -0.004, \"Q4_mean_vc\": 0.921, \"Q1_headroom\": 0.169, \"Q4_headroom\": 0.048, \"overall_lp_delta\": 0.006, \"n\": 529}, \"scierc_re\": {\"Q1_lp_delta\": -0.036, \"Q2_lp_delta\": -0.021, \"Q3_lp_delta\": -0.022, \"Q4_lp_delta\": 0.04, \"Q4_mean_vc\": 0.894, \"Q1_headroom\": 0.211, \"Q4_headroom\": 0.145, \"overall_lp_delta\": -0.009, \"n\": 397}, \"conll_ner\": {\"Q1_lp_delta\": -0.037, \"Q2_lp_delta\": -0.005, \"Q3_lp_delta\": 0, \"Q4_lp_delta\": 0, \"overall_lp_delta\": -0.01, \"n\": 2756, \"note\": \"Q3/Q4 degenerate (VC=1.0, all samples identical)\"}, \"conclusion\": \"VC stratification does not solve LP compression for NER. RE Q4 is only exception (+0.040).\"}}, \"exp_llama3b_scierc_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:45:23.638Z\", \"updated_at\": \"2026-05-16T03:59:26.005Z\", \"hypothesis\": \"Cross-family scale ablation: LLaMA 3.2-3B on SciERC NER. Verify correlation-selection gap generalizes across model families AND scales. Compare with LLaMA 8B results.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.2-3b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/review_round9_experiments/llama3b_scierc/\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"LLaMA-3.2-3B-Instruct (LoRA r=32 SciERC fine-tuned)\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/llama3.2-3b-scierc-merged\", \"log_path\": \"output/review_round9_experiments/llama3b_scierc/inference.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:59:16.198Z\", \"metrics\": {\"ner_full\": {\"SJ_rho\": 0.3754, \"FK_rho\": 0.2676, \"LP_rho\": 0.2662, \"EM_rho\": 0.3341, \"VC_rho\": 0.4602, \"SJ_auroc\": 0.7383, \"FK_auroc\": 0.6714, \"LP_auroc\": 0.633, \"EM_auroc\": 0.7763, \"VC_auroc\": 0.7429, \"n\": 529}, \"ner_cond\": {\"SJ_rho\": 0.3445, \"FK_rho\": 0.2125, \"LP_rho\": 0.2099, \"EM_rho\": 0.3952, \"VC_rho\": 0.3815, \"SJ_auroc\": 0.7292, \"FK_auroc\": 0.66, \"LP_auroc\": 0.6156, \"EM_auroc\": 0.7822, \"VC_auroc\": 0.7222, \"n\": 476}, \"greedy_f1\": 0.6267, \"oracle_f1\": 0.763, \"oracle_headroom\": 0.1363, \"selection_f1_SJ\": 0.6328, \"selection_f1_VC\": 0.6113, \"selection_f1_FK\": 0.6295, \"selection_f1_EM\": 0.6174, \"selection_f1_LP\": 0.6279, \"n_gold_empty\": 22, \"structural_beats_surface\": true, \"rho_advantage_SJ_over_FK\": 0.1078}}, \"exp_freeform_conll_4seed\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:45:17.133Z\", \"updated_at\": \"2026-05-16T03:04:49.550Z\", \"hypothesis\": \"Free-form CoNLL NER 4-seed ablation: verify LP compression is cross-dataset intrinsic (not SciERC-specific). 4 seeds × N=8, T=1.0 on CoNLL, compare LP range distribution with constrained decoding.\", \"spec\": {\"command\": \"python run_freeform_conll.py --seed {42,123,456,789} --gpu {0,1,2,3} --n_samples 8 --temperature 1.0\", \"server\": \"autodl-4x5090\", \"data_path\": \"data/conll2003/test.jsonl\", \"data_count\": 3453, \"model_name\": \"checkpoints/qwen3-8b-conll2003-merged\", \"seed\": \"42,123,456,789\"}, \"checkpoint_path\": \"N/A (inference-only experiment)\", \"log_path\": \"output/review_round9_experiments/freeform_conll/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:04:40.278Z\", \"metrics\": {\"greedy_f1\": \"0.9035±0.0004\", \"oracle_f1\": \"0.9460±0.0023\", \"lp_range_median\": \"0.0581±0.0072\", \"rho_sj\": \"0.4606±0.0188\", \"rho_fk\": \"0.4372±0.0209\", \"rho_em\": \"0.4714±0.0168\", \"rho_vc\": \"0.4606±0.0138\", \"rho_lp\": \"0.3262±0.0120\", \"sel_f1_sj\": \"0.8994±0.0014\", \"sel_f1_vc\": \"0.9006±0.0026\", \"sel_f1_lp\": \"0.8958±0.0009\", \"seeds\": [42, 123, 456, 789], \"n_samples\": 8, \"temperature\": 1, \"instances\": 2756, \"gold_empty_filtered\": 697}}, \"exp_qwen3_4b_conll_merge_inference_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:42:42.107Z\", \"updated_at\": \"2026-05-15T20:07:12.593Z\", \"hypothesis\": \"CoNLL 4B checkpoint-4200 (best from resume training) merge + SCS inference. Replaces v1 which used checkpoint-3800 merged model. Cross-scale evidence for correlation-selection gap.\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-conll2003-merged-ckpt4200 --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_conll_merge_inference_v2\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-4B (LoRA merged, ckpt-4200)\", \"seed\": 42, \"checkpoint_source\": \"exp_qwen3_4b_conll_finetune_resume (checkpoint-4200)\"}, \"checkpoint_path\": \"N/A - duplicate\", \"log_path\": \"N/A - duplicate\", \"conclusion\": \"killed\", \"notes\": \"Superseded by exp_qwen3_4b_conll_scs_inference_v2. Output was empty (dead experiment), functionally duplicate.\", \"completed_at\": \"2026-05-15T20:03:47.431Z\"}, \"exp_qwen3_4b_scierc_merge_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:42:43.332Z\", \"updated_at\": \"2026-05-15T20:04:15.433Z\", \"hypothesis\": \"SciERC 4B best checkpoint merge + SCS inference. Complete 2x2 scale matrix (4B SciERC cell). Cross-scale + cross-task evidence for correlation-selection gap.\", \"checkpoint_path\": \"N/A - superseded\", \"log_path\": \"N/A - superseded\", \"conclusion\": \"killed\", \"notes\": \"Superseded by exp_qwen3_4b_scierc_scs_inference. Never launched (stuck in PREPARING). Killed during registry cleanup.\", \"completed_at\": \"2026-05-15T20:04:15.433Z\"}, \"exp_qwen3_4b_scierc_finetune_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:24:45.518Z\", \"updated_at\": \"2026-05-15T19:39:04.438Z\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scierc_4b.yaml\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"226610\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v3.log\", \"submitted_at\": \"2026-05-15T19:24:55.461Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"wall_clock_seconds\": 849.0, \"gpu_hours\": 0.24}, \"conclusion\": \"failed\", \"notes\": \"OOM on cuda:2 — freeform inference (seed789, 8B) 占满 GPU 2。未实际训练。重启为 v4 on cuda:0。\", \"completed_at\": \"2026-05-15T19:39:04.438Z\"}, \"exp_qwen3_4b_conll_finetune_resume\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:38:19.388Z\", \"updated_at\": \"2026-05-15T19:38:43.468Z\", \"hypothesis\": \"CoNLL 4B NER LoRA fine-tune resume from checkpoint-3800. Cross-scale evidence for correlation-selection gap.\", \"spec\": {\"hypothesis\": \"CoNLL2003 NER LoRA fine-tune with Qwen3-4B, resume from checkpoint-3800 to complete 5 epochs\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_conll2003_4b_resume.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"data_path\": \"data/conll2003/llmfactory_train.json\", \"data_count\": 14042, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"resume_from\": \"checkpoint-3800\", \"lora_rank\": 32, \"lora_alpha\": 64, \"num_train_epochs\": 5, \"learning_rate\": 0.0002, \"batch_size\": \"2 x 8 grad_accum\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-lora\", \"best_checkpoint\": \"checkpoint-4200\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-lora/trainer_state.json\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.001136, \"eval_loss\": 0.0225, \"best_global_step\": 4200, \"best_metric_eval_loss\": 0.0225, \"total_steps\": 4390, \"epochs\": 5, \"train_runtime_sec\": 1185.8, \"train_samples_per_second\": 59.2, \"resumed_from_step\": 3800}, \"completed_at\": \"2026-05-15T19:38:43.468Z\"}, \"exp_qwen3_4b_scierc_finetune_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:03:49.204Z\", \"updated_at\": \"2026-05-15T19:24:32.466Z\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scierc_4b.yaml\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": \"219830\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v2.log\", \"submitted_at\": \"2026-05-15T19:05:31.524Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 1861, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"D096\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-scierc-lora/\", \"wall_clock_seconds\": 1122.6, \"gpu_hours\": 0.31}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T19:24:14.124Z\", \"notes\": \"PID 219830 已死，仅完成 step 10，无 checkpoint。需彻底重启。\"}, \"exp_qwen3_4b_conll_finetune\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-15T17:18:35.501Z\", \"updated_at\": \"2026-05-15T19:10:24.822Z\", \"hypothesis\": \"Scale ablation: Qwen3-4B CoNLL NER LoRA fine-tune to provide cross-scale evidence (vs 8B). Verify correlation-selection gap, SJ>FK ordering, and LP compression generalize across model scale.\", \"reproduce\": {\"finished_at\": \"2026-05-15T18:45:42.215Z\"}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-15T18:45:43.672Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:45:49.686191+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli train train_config_conll2003_4b.yaml\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"data_path\": \"data/conll2003\", \"data_count\": 14041, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"D096\", \"log_path\": \"checkpoints/qwen3-4b-conll2003-lora/trainer_log.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-lora\", \"lora_config\": {\"trainable_params\": \"66M / 4.09B (1.62%)\", \"target_modules\": \"q_proj, k_proj, v_proj, o_proj, gate_proj, up_proj, down_proj\", \"epochs\": 5, \"batch_size\": 16, \"total_steps\": 4390, \"enable_thinking\": false}}, \"conclusion\": \"success\", \"notes\": \"Training stopped at step 3920/4390 (89.3%, epoch 4.46/5). No error log or tmux session found. checkpoint-3800 is valid (adapter_model.safetensors 264MB, eval_loss=0.023). Proceeding with checkpoint-3800 for merge+inference.\", \"metrics\": {\"final_loss\": 0.0086, \"total_steps_completed\": 3920, \"total_steps_target\": 4390, \"epochs_completed\": 4.46, \"epochs_target\": 5, \"best_checkpoint\": \"checkpoint-3800\", \"note\": \"Training stopped at 89.3% completion (no error log found). Using checkpoint-3800 (loss ~0.01) for merge.\"}}, \"exp_freeform_seed789_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:02:03.813Z\", \"updated_at\": \"2026-05-15T19:06:44.537Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python run_freeform_inference.py --seed 789 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed789\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"218882\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_seed789_v2.log\", \"submitted_at\": \"2026-05-15T19:02:03.527Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"hypothesis\": \"Multi-seed free-form ablation (seed=789): third seed for 3-seed mean±σ statistical significance. Verify RE LP flip and NER gap stability.\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 789, \"wall_clock_seconds\": 274.9, \"gpu_hours\": 0.08}, \"reproduce\": {\"finished_at\": \"2026-05-15T19:06:37.887Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T19:06:38.388Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T19:06:53.109123+00:00\"}]}}, \"exp_qwen3_4b_scierc_finetune\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:58:58.948Z\", \"updated_at\": \"2026-05-15T19:03:05.505Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli train train_config_scierc_4b.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"218258\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune.log\", \"submitted_at\": \"2026-05-15T19:00:10.234Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 175.3, \"gpu_hours\": 0.05}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:03:05.505Z\"}, \"exp_lp_t07_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:34:12.094Z\", \"updated_at\": \"2026-05-15T16:30:35.531Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 8 --temperature 0.7 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_lp_t07_scierc\\\"\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-8B (LoRA fine-tuned on SciERC, ft_002_v2 merged)\", \"seed\": 42, \"gpu\": \"cuda:1\", \"hyperparams\": {\"n_samples\": 8, \"temperature\": 0.7, \"max_tokens\": 1024}}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T16:28:29.563Z\"}, \"exp_lp_scierc_t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:34:06.918Z\", \"updated_at\": \"2026-05-15T16:03:13.881Z\", \"hypothesis\": \"LP T=0.7 推理：验证低温下 LP score compression 是否依然存在，强化 \\\"LP compression is model/task intrinsic\\\" claim。对比 T=1.0 的 LP range 分布。\", \"spec\": {\"command\": \"python run_sc_ie.py --dataset scierc --subtask ner --model qwen --n_samples 8 --temperature 0.7 --use_logprob --output_dir /root/autodl-tmp/struct_self_consist_ie/output/exp_lp_scierc_t07\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"196993\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_lp_scierc_t07/\", \"submitted_at\": \"2026-05-15T15:35:31.692Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"SciERC\", \"data_count\": 500, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_lp_scierc_t07/report.json\", \"wall_clock_seconds\": 1206.2, \"gpu_hours\": 0.34}, \"conclusion\": \"success\", \"metrics\": {\"ner_greedy_f1\": 0.662, \"ner_oracle_f1\": 0.764, \"ner_headroom_pp\": 10.2, \"ner_rho_sj_full\": 0.365, \"ner_rho_sj_cond\": 0.363, \"ner_rho_fk_full\": 0.289, \"ner_rho_fk_cond\": 0.255, \"lp_rho_full\": 0.249, \"lp_rho_cond\": 0.185, \"ner_rho_advantage\": 0.076, \"zero_f1_pct\": 11, \"full_n\": 529, \"cond_n\": 477, \"verdict\": \"success_supports_LP_compression_claim\"}, \"completed_at\": \"2026-05-15T15:55:37.889Z\"}, \"exp_re_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:40:40.607Z\", \"updated_at\": \"2026-05-15T15:55:41.890Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_re_scierc_seed456\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"199161\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed456/\", \"submitted_at\": \"2026-05-15T15:40:59.585Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"SciERC\", \"data_count\": 500, \"model_name\": \"Qwen3-8B (SciERC merged)\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed456/report.json\", \"wall_clock_seconds\": 882.3, \"gpu_hours\": 0.25}, \"hypothesis\": \"SciERC RE 多种子验证 (seed456): 解决 R4-W1/R7-C1 single-seed RE 弱点。与 seed42 (exp_012_rerun_1024) 对齐，joint subtask N=8 T=1.0。目标: 3-seed RE selection F1 mean±σ。\", \"conclusion\": \"negative\", \"metrics\": {\"ner_greedy_f1\": 0.664, \"ner_oracle_f1\": 0.775, \"ner_headroom_pp\": 11.1, \"ner_rho_sj_cond\": 0.283, \"ner_rho_fk_cond\": 0.145, \"re_greedy_f1\": 0.417, \"re_oracle_f1\": 0.581, \"re_headroom_pp\": 16.3, \"re_rho_sj_cond\": 0.315, \"re_rho_fk_cond\": 0.123, \"re_zero_f1_pct\": 45.3, \"verdict\": \"FAIL_re_rho_sj_below_040\"}, \"completed_at\": \"2026-05-15T15:55:41.890Z\"}, \"exp_re_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:40:38.271Z\", \"updated_at\": \"2026-05-15T15:55:40.000Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_re_scierc_seed123\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"199021\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed123/\", \"submitted_at\": \"2026-05-15T15:40:58.073Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"SciERC\", \"data_count\": 500, \"model_name\": \"Qwen3-8B (SciERC merged)\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed123/report.json\", \"wall_clock_seconds\": 881.9, \"gpu_hours\": 0.24}, \"hypothesis\": \"SciERC RE 多种子验证 (seed123): 解决 R4-W1/R7-C1 single-seed RE 弱点。与 seed42 (exp_012_rerun_1024) 对齐，joint subtask N=8 T=1.0。目标: 3-seed RE selection F1 mean±σ。\", \"conclusion\": \"negative\", \"metrics\": {\"ner_greedy_f1\": 0.663, \"ner_oracle_f1\": 0.786, \"ner_headroom_pp\": 12.3, \"ner_rho_sj_cond\": 0.404, \"ner_rho_fk_cond\": 0.182, \"re_greedy_f1\": 0.42, \"re_oracle_f1\": 0.593, \"re_headroom_pp\": 17.3, \"re_rho_sj_cond\": 0.277, \"re_rho_fk_cond\": 0.063, \"re_zero_f1_pct\": 43.6, \"verdict\": \"FAIL_re_rho_sj_below_040\"}, \"completed_at\": \"2026-05-15T15:55:40.000Z\"}, \"exp_017_llama_conll_n8_t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:29:34.595Z\", \"updated_at\": \"2026-05-15T15:46:22.722Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.7 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n8_t07\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"195927\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_017_llama_conll_n8_t07.log\", \"submitted_at\": \"2026-05-15T15:31:17.989Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 881.3, \"gpu_hours\": 0.24}, \"hypothesis\": \"LLaMA CoNLL N=8 T=0.7 防御性实验：填补\\\"LLaMA 仅在 SciERC 上测过\\\"的弱点，验证 cross-model consistency（vs Qwen CoNLL）。T=0.7 低温下 confidence signals 的 correlation-selection gap 是否依然存在。\", \"parent\": \"exp_017_llama_conll\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-15T15:31:15.772Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.7 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n8_t07\\\"\", \"finished_at\": \"2026-05-15T15:40:02.605Z\", \"training_hours\": 0.15}, \"pid\": \"195927\", \"log_path\": \"/root/runs/struct_self_consist_ie/exp_017_llama_conll_n8_t07.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:40:08.277684+00:00\"}]}, \"metrics\": {\"n_valid\": 2756, \"greedy_f1\": 0.9242, \"oracle_f1\": 0.9391, \"lp_range_median\": 1.1e-05, \"lp_tied_fraction_005\": 0.9579, \"signals\": {\"SJ\": {\"rho\": 0.3934, \"auroc\": 0.6506}, \"FK\": {\"rho\": 0.3879, \"auroc\": 0.6488}, \"VC\": {\"rho\": 0.375, \"auroc\": 0.6551}, \"EM\": {\"rho\": 0.3888, \"auroc\": 0.6494}, \"LP\": {\"rho\": 0.2951, \"auroc\": 0.7509}}, \"selection_f1\": {\"SJ\": 0.9247, \"FK\": 0.9254, \"VC\": 0.9264, \"EM\": 0.9255, \"LP\": 0.9248}}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (inference-only)\", \"completed_at\": \"2026-05-15T15:45:59.311Z\"}, \"exp008_re_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:50.987Z\", \"updated_at\": \"2026-05-15T12:41:39.774Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp008_re_n16 && CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp008_re_n16 --collect_logprobs 2>&1 | tee output/exp008_re_n16/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:2\"], \"pid\": \"53600\", \"log_path\": \"~/runs/struct_self_consist_ie/exp008_re_n16.log\", \"submitted_at\": \"2026-05-14T12:15:14.917Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_008_re_n16_v2 (full 551-instance run on autodl-5090)\", \"wall_clock_seconds\": 87984.9, \"gpu_hours\": 24.44}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T12:41:39.774Z\"}, \"exp001_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:48.078Z\", \"updated_at\": \"2026-05-15T12:41:32.192Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp001_n16_seed456 && CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --output_dir output/exp001_n16_seed456 --collect_logprobs 2>&1 | tee output/exp001_n16_seed456/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:1\"], \"pid\": \"50302\", \"log_path\": \"~/runs/struct_self_consist_ie/exp001_seed456.log\", \"submitted_at\": \"2026-05-14T12:12:41.206Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed456_v2_ner (NER-only on autodl-5090)\", \"wall_clock_seconds\": 88131.0, \"gpu_hours\": 24.48}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:32.192Z\"}, \"exp001_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:45.739Z\", \"updated_at\": \"2026-05-15T12:41:31.168Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp001_n16_seed123 && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --output_dir output/exp001_n16_seed123 --collect_logprobs 2>&1 | tee output/exp001_n16_seed123/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"48530\", \"log_path\": \"~/runs/struct_self_consist_ie/exp001_seed123.log\", \"submitted_at\": \"2026-05-14T12:09:45.674Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed123_v2 (NER-only, 551 instances on autodl-5090)\", \"wall_clock_seconds\": 88305.5, \"gpu_hours\": 24.53}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:31.168Z\"}, \"exp_001_n16_seed456_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:44:31.348Z\", \"updated_at\": \"2026-05-15T12:41:30.065Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --num_test 9999 --output_dir output/exp001_n16_seed456/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:1\"], \"pid\": \"62170\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_n16_seed456_full.log\", \"submitted_at\": \"2026-05-14T12:44:31.087Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed456_v2_ner (NER-only on autodl-5090)\", \"wall_clock_seconds\": 86219.0, \"gpu_hours\": 23.95}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:30.065Z\"}, \"exp_001_n16_seed123_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:43:47.915Z\", \"updated_at\": \"2026-05-15T12:41:29.068Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --num_test 9999 --output_dir output/exp001_n16_seed123_full/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"61812\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_n16_seed123_full.log\", \"submitted_at\": \"2026-05-14T12:44:06.059Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed123_v2 (NER-only on autodl-5090)\", \"wall_clock_seconds\": 86243.0, \"gpu_hours\": 23.96}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:29.068Z\"}, \"exp_007_ner_llama\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:21.510Z\", \"updated_at\": \"2026-05-15T12:41:27.410Z\", \"spec\": {\"description\": \"Fine-tune LLaMA-3.1-8B on SciERC + NER pilot (N=8, T=0.7). Model-agnostic validation.\", \"hypothesis\": \"SJ advantage is model-agnostic, not Qwen3-specific\", \"plan_id\": \"exp-007\", \"claim\": 1, \"model_name\": \"llama-3.1-8b-instruct (new fine-tune)\", \"dataset\": \"SciERC\", \"priority\": \"P0\", \"failure_reason\": \"Superseded by exp_007_ner_multi_model + exp_007_llama_inference (completed on autodl-5090)\"}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_007_llama_inference (DONE)\", \"notes\": \"Completed as exp_007_llama_n16 on autodl-5090. Registry status corrected.\", \"completed_at\": \"2026-05-15T12:41:27.410Z\"}, \"exp_002_merge_conll2003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:25:56.211Z\", \"updated_at\": \"2026-05-15T12:41:26.419Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli export export_config_conll2003.yaml > /tmp/merge_conll2003.log 2>&1 && echo 'MERGE_DONE' >> /tmp/merge_conll2003.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"57524\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_merge_conll2003.log\", \"submitted_at\": \"2026-05-14T12:25:56.139Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_002_ner_conll2003 (completed on autodl-5090)\", \"wall_clock_seconds\": 87330.3, \"gpu_hours\": 24.26}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_002_ner_conll2003 (DONE)\", \"notes\": \"Completed as exp_002_conll_n16 on autodl-5090. Registry status corrected.\", \"completed_at\": \"2026-05-15T12:41:26.419Z\"}, \"exp_019_supervised_verifier\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:08:54.395Z\", \"updated_at\": \"2026-05-15T12:40:53.995Z\", \"spec\": {\"hypothesis\": \"Supervised verifier (DeBERTa-v3-large) can close the correlation-selection gap, proving the gap is closable with supervision\", \"plan_id\": \"exp-019\", \"model_name\": \"microsoft/deberta-v3-large\", \"data_path\": \"output/exp_012_rerun_1024/samples.jsonl\", \"data_count\": 551, \"seed\": 42}, \"conclusion\": \"killed\", \"notes\": \"Cancelled by Director: DDL risk too high (3-4 days for implementation+training+eval+paper), scope creep for analytical paper, free-form ablation already provides sufficient mechanistic evidence\", \"completed_at\": \"2026-05-15T12:40:53.995Z\"}, \"exp_018_llama_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:15.150Z\", \"updated_at\": \"2026-05-15T06:22:40.868Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: LLaMA SciERC N=8 seed=456, max_tokens=1024. Fresh inference (D066 decision: replace exp_007 re-analysis with independent replication).\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed456_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T06:08:05.756Z\", \"notes\": \"SUPERSEDED by exp_018_llama_scierc_seed456_r1024 (D066). Original data was re-analysis of exp_007_llama_seed456, not independent inference. Fresh rerun with explicit max_tokens=1024 now canonical.\"}, \"exp_002_conll_n16_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:57.682Z\", \"updated_at\": \"2026-05-15T01:20:53.108Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen CoNLL N=16.\", \"parent\": \"exp_002_conll_n16\", \"model_name\": \"qwen3-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_002_conll_n16_r1024\", \"data_path\": \"data/conll2003\", \"data_count\": 3453}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:53.108Z\"}, \"exp_007_llama_n16_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:59.685Z\", \"updated_at\": \"2026-05-15T01:20:52.194Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA SciERC N=16.\", \"parent\": \"exp_007_llama_n16\", \"model_name\": \"llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_007_llama_n16_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:52.194Z\"}, \"exp_001_seed123_v2_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:54.442Z\", \"updated_at\": \"2026-05-15T01:20:49.812Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed123.\", \"parent\": \"exp_001_seed123_v2\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 123, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed123_v2_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 529}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:49.812Z\"}, \"exp_001_seed456_v2_ner_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:55.975Z\", \"updated_at\": \"2026-05-15T01:20:48.914Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed456.\", \"parent\": \"exp_001_seed456_v2_ner\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 456, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed456_v2_ner_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:48.914Z\"}, \"exp_001_seed42_v2_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:52.571Z\", \"updated_at\": \"2026-05-14T22:28:53.686Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed42.\", \"parent\": \"exp_001_seed42_v2\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed42_v2_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"metrics\": {\"greedy_f1\": 0.6647, \"oracle_f1\": 0.8106, \"softjaccard_rho_full\": 0.3928, \"fleiss_rho_full\": 0.2489, \"logprob_rho_full\": 0.2136, \"softjaccard_rho_cond\": 0.3455, \"fleiss_rho_cond\": 0.163, \"logprob_rho_cond\": 0.1624, \"verdict\": \"MARGINAL\"}, \"checkpoint_path\": \"output/exp_001_seed42_v2_r1024\", \"log_path\": \"output/exp_001_seed42_v2_r1024/run.log\", \"completed_at\": \"2026-05-14T22:27:43.836Z\"}, \"exp_017_llama_conll_n16_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:23:21.987Z\", \"updated_at\": \"2026-05-14T20:24:45.875Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=456: structural>surface ranking preserved across seeds, complementing Qwen SciERC 3-seed protocol\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --num_test 9999 --output_dir output/exp_017_llama_conll_n16_s456\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"llama3.1-8b-conll2003-merged\", \"seed\": 456}, \"metrics\": {\"greedy_f1\": 0.9243, \"oracle_f1\": 0.9488, \"oracle_headroom\": 0.0245, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4552, \"SJ_AUROC\": 0.7288, \"SJ_ECE\": 0.1134, \"FK_rho\": 0.4478, \"FK_AUROC\": 0.7248, \"FK_ECE\": 0.109, \"logprob_rho\": 0.3078, \"logprob_AUROC\": 0.7612, \"logprob_ECE\": 0.1289, \"EM_rho\": 0.452, \"EM_AUROC\": 0.7275, \"EM_ECE\": 0.1082, \"voting_conf_rho\": 0.4571, \"voting_conf_AUROC\": 0.7348, \"voting_conf_ECE\": 0.0863}, \"conditional\": {\"SJ_rho\": 0.4505, \"SJ_AUROC\": 0.7449, \"SJ_ECE\": 0.0826, \"FK_rho\": 0.4422, \"FK_AUROC\": 0.7401, \"FK_ECE\": 0.0835, \"logprob_rho\": 0.3242, \"logprob_AUROC\": 0.8067, \"logprob_ECE\": 0.0921, \"EM_rho\": 0.451, \"EM_AUROC\": 0.745, \"EM_ECE\": 0.0756, \"voting_conf_rho\": 0.3962, \"voting_conf_AUROC\": 0.7202, \"voting_conf_ECE\": 0.0746}, \"best_of_n\": {\"greedy\": 0.9243, \"random_avg\": 0.9215, \"sj_best\": 0.9243, \"logprob_best\": 0.9243, \"voting_conf_best\": 0.9243, \"oracle\": 0.9488}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0238, \"full_FK_rho_delta\": 0.0201, \"full_logprob_rho_delta\": 0.0006, \"full_EM_rho_delta\": 0.0214, \"full_voting_conf_rho_delta\": 0.0315, \"cond_SJ_rho_delta\": 0.0149, \"cond_FK_rho_delta\": 0.0112, \"cond_logprob_rho_delta\": -0.004, \"cond_EM_rho_delta\": 0.0107, \"cond_voting_conf_rho_delta\": 0.0219}}, \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s456/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16_s456/all_signals_report.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T20:24:45.875Z\"}, \"exp_017_llama_conll_n16_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:23:21.084Z\", \"updated_at\": \"2026-05-14T19:43:06.607Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=123: structural>surface ranking preserved across seeds, complementing Qwen SciERC 3-seed protocol\", \"spec\": {\"hypothesis\": \"LLaMA CoNLL-2003 NER N=16 seed=123: cross-seed robustness check against N=8 seed=42 baseline (exp_017_llama_conll_infer)\", \"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --num_test 9999 --output_dir output/exp_017_llama_conll_n16_s123\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 3453, \"model_name\": \"llama3.1-8b-conll2003-merged\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/llama3.1-8b-conll2003-merged\", \"eval_data\": \"data/conll2003\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s123/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16_s123.log\"}, \"metrics\": {\"greedy_f1\": 0.9266, \"oracle_f1\": 0.9497, \"oracle_headroom\": 0.0231, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4698, \"SJ_AUROC\": 0.7402, \"SJ_ECE\": 0.1135, \"FK_rho\": 0.4594, \"FK_AUROC\": 0.7351, \"FK_ECE\": 0.1114, \"logprob_rho\": 0.3161, \"logprob_AUROC\": 0.768, \"logprob_ECE\": 0.129, \"EM_rho\": 0.4676, \"EM_AUROC\": 0.7399, \"EM_ECE\": 0.1082, \"voting_conf_rho\": 0.4612, \"voting_conf_AUROC\": 0.7429, \"voting_conf_ECE\": 0.0832}, \"conditional\": {\"SJ_rho\": 0.4712, \"SJ_AUROC\": 0.7609, \"SJ_ECE\": 0.0828, \"FK_rho\": 0.4595, \"FK_AUROC\": 0.7547, \"FK_ECE\": 0.0858, \"logprob_rho\": 0.3314, \"logprob_AUROC\": 0.8134, \"logprob_ECE\": 0.0922, \"EM_rho\": 0.4732, \"EM_AUROC\": 0.7626, \"EM_ECE\": 0.075, \"voting_conf_rho\": 0.4086, \"voting_conf_AUROC\": 0.7338, \"voting_conf_ECE\": 0.0706}, \"best_of_n\": {\"greedy\": 0.9242, \"random_avg\": 0.9216, \"sj_best\": 0.9247, \"logprob_best\": 0.9253, \"voting_conf_best\": 0.9255, \"oracle\": 0.9486}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0384, \"full_FK_rho_delta\": 0.0317, \"full_logprob_rho_delta\": 0.0089, \"full_SJ_AUROC_delta\": 0.0363, \"full_FK_AUROC_delta\": 0.0325, \"full_logprob_AUROC_delta\": 0.007, \"cond_SJ_rho_delta\": 0.0356, \"cond_FK_rho_delta\": 0.0285, \"cond_logprob_rho_delta\": 0.0032}}, \"log_path\": \"output/exp_017_llama_conll_n16_s123.log\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s123/samples.jsonl\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T19:43:06.607Z\"}, \"exp_008_re_n16_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:45:10.852Z\", \"updated_at\": \"2026-05-14T17:51:43.957Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs --num_test 9999 --output_dir output/exp008_re_n16/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:2\"], \"pid\": \"62585\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_008_re_n16_full.log\", \"submitted_at\": \"2026-05-14T12:45:10.764Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 18393.2, \"gpu_hours\": 5.11}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_008_re_n16_t10_full (full 551-instance RE-only run on autodl-5090)\", \"completed_at\": \"2026-05-14T17:51:43.957Z\"}, \"exp_001_n16_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:10:29.393Z\", \"updated_at\": \"2026-05-14T12:42:58.393Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs\", \"server\": \"gpu-5090-4x-2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"num_instances\": 200, \"partial\": true, \"note\": \"Only 200/551 instances due to --num_test default bug. Needs full rerun.\"}, \"metrics\": {\"ner\": {\"greedy_f1\": 0.655, \"oracle_f1\": 0.8028, \"headroom\": 0.1478, \"rho_sj_full\": 0.4076, \"rho_fk_full\": 0.2799, \"rho_logprob_full\": 0.3189, \"rho_sj_cond\": 0.4271, \"rho_fk_cond\": 0.2743, \"rho_logprob_cond\": 0.2835, \"sj_beats_fk\": true, \"rho_advantage\": 0.1277}, \"re\": {\"greedy_f1\": 0.4243, \"oracle_f1\": 0.6771, \"headroom\": 0.2528, \"rho_sj_full\": 0.2943, \"rho_fk_full\": 0.2657, \"rho_logprob_full\": 0.3005, \"rho_sj_cond\": 0.4003, \"rho_fk_cond\": 0.313, \"rho_logprob_cond\": 0.2317, \"sj_beats_fk\": true, \"rho_advantage\": 0.0286}, \"verdict\": \"FAIL\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp001_n16_seed123/\", \"completed_at\": \"2026-05-14T12:28:38.104Z\"}, \"exp_016_signal_ensemble\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:15:23.771Z\", \"updated_at\": \"2026-05-14T12:42:55.931Z\", \"spec\": {\"command\": \"python code/analyze_exp016_ensemble.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"model_name\": \"N/A (CPU-only analysis)\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"eval_data\": \"pilot_004\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp016_signal_ensemble/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:15:53.341Z\", \"metrics\": {\"sj_logprob_pearson_ner\": 0.57, \"sj_logprob_pearson_re\": 0.42, \"best_linear_ner\": {\"combo\": \"SJ+voting_conf\", \"alpha\": 0.3, \"rho\": 0.489}, \"best_linear_re\": {\"combo\": \"voting_conf+logprob\", \"alpha\": 0.6, \"rho\": 0.429}, \"ensemble_ner_auroc\": 0.735, \"ensemble_re_auroc\": 0.719, \"best_single_ner_auroc\": 0.7, \"best_single_re_auroc\": 0.721, \"ensemble_ner_delta\": 0.035, \"selection_f1_ner\": {\"greedy\": 0.609, \"logprob\": 0.609, \"sj\": 0.604, \"ensemble\": 0.604, \"voting\": 0.596, \"random\": 0.58, \"oracle\": 0.769}, \"selection_f1_re\": {\"logprob\": 0.397, \"greedy\": 0.374, \"sj\": 0.368, \"ensemble\": 0.367, \"voting\": 0.338, \"random\": 0.338, \"oracle\": 0.561}, \"diagnosis\": \"SJ+voting_conf linear combo boosts NER ρ to 0.489 (+23%). RE: logprob-best is ONLY method beating greedy (0.397 vs 0.374). Ensemble AUROC +0.035 on NER. Oracle gap still huge.\"}}, \"exp_001_ner_n16_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:10.898Z\", \"updated_at\": \"2026-05-14T12:42:49.592Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp001_n16_seed42 --num_test 9999 --collect_logprobs 2>&1 | tee output/exp001_n16_seed42_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"54357\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_ner_n16_scierc.log\", \"submitted_at\": \"2026-05-14T12:15:46.646Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T11:43:48.643Z\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:55:45.664Z\", \"metrics\": {\"n_instances\": 551, \"ner_n\": 529, \"re_n\": 397, \"N\": 16, \"T\": 1, \"seed\": 42, \"full_test_set\": true, \"ner_voting_conf_rho\": 0.399, \"ner_sj_rho\": 0.398, \"ner_em_rho\": 0.339, \"ner_fk_rho\": 0.288, \"ner_logprob_rho\": 0.237, \"ner_voting_conf_auroc\": 0.704, \"ner_sj_auroc\": 0.697, \"ner_cond_em_rho\": 0.414, \"ner_cond_sj_rho\": 0.349, \"ner_cond_vc_rho\": 0.34, \"re_voting_conf_rho\": 0.38, \"re_logprob_rho\": 0.293, \"re_fk_rho\": 0.281, \"re_sj_rho\": 0.277, \"re_em_rho\": 0.148, \"re_voting_conf_auroc\": 0.699, \"re_cond_em_rho\": 0.475, \"re_cond_sj_rho\": 0.318, \"re_cond_vc_rho\": 0.35, \"re_cond_em_auroc\": 0.742, \"diagnosis\": \"551 instances T=1.0: voting_conf best on full set (NER 0.399, RE 0.380). EM SURPRISE best on conditional set (NER cond 0.414, RE cond 0.475). RE full FAIL (SJ 0.277 < 0.40). Previous N-scaling 'breakthrough' was artifact of 200 instances + T=0.7.\"}}, \"exp_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:39:53.226Z\", \"updated_at\": \"2026-05-14T12:40:17.202Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --collect_logprobs --num_test 99999\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-lora-merged\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll2003-merged\", \"log_path\": \"/tmp/pilot_conll2003.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:40:08.402Z\", \"metrics\": {\"sj_rho_full\": 0.4357, \"sj_tau_full\": 0.3851, \"sj_auroc_full\": 0.8008, \"sj_rho_cond\": 0.4511, \"fk_rho_full\": 0.3998, \"fk_tau_full\": 0.3568, \"fk_auroc_full\": 0.7741, \"fk_rho_cond\": 0.4064, \"logprob_rho_full\": 0.3157, \"logprob_tau_full\": 0.2469, \"logprob_auroc_full\": 0.7532, \"logprob_rho_cond\": 0.3562, \"em_rho_full\": 0.4507, \"em_tau_full\": 0.4002, \"em_auroc_full\": 0.8156, \"em_rho_cond\": 0.4799, \"ev_rho_full\": 0.4237, \"ev_tau_full\": 0.3777, \"ev_auroc_full\": 0.7889, \"ev_rho_cond\": 0.4127, \"greedy_f1\": 0.9123, \"oracle_f1\": 0.9543, \"voting_f1\": 0.9141, \"oracle_headroom\": 0.042, \"sj_vs_logprob_delta_rho\": 0.12, \"sj_vs_logprob_ci_low\": 0.0881, \"sj_vs_logprob_ci_high\": 0.154, \"sj_vs_logprob_significant\": true, \"n_instances\": 3453, \"n_valid\": 2756, \"n_samples\": 8, \"temperature\": 1}}, \"exp_002_ner_conll2003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:15.223Z\", \"updated_at\": \"2026-05-14T12:27:35.413Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp002_conll2003 --num_test 99999 --seed 42 --collect_logprobs 2>&1 | tee /tmp/pilot_conll2003.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"58208\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_ner_conll2003.log\", \"submitted_at\": \"2026-05-14T12:27:35.337Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-14T11:43:49.959Z\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll2003-lora\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_ner_conll2003.log\", \"completed_at\": \"2026-05-14T12:18:04.097Z\"}, \"exp_004_re_diagnostic\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:49:44.497Z\", \"updated_at\": \"2026-05-14T11:50:24.620Z\", \"spec\": {\"hypothesis\": \"RE diagnostic: per-relation-type breakdown reveals which types drive low RE rho; error propagation and threshold sensitivity clarify the gap between NER and RE consistency signals\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Per-relation-type SJ/FK/voting rho, error propagation classification, threshold sensitivity, bootstrap CI, Fisher z-test NER vs RE\", \"command\": \"python3 code/analyze_exp004_re_diagnostic.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004_re_diagnostic\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004_re_diagnostic/\", \"checkpoint_source\": \"mvp_pilot_004\", \"eval_data\": \"scierc_test_551\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:50:04.662Z\", \"metrics\": {\"per_relation_type\": {\"HYPONYM-OF\": {\"n\": 36, \"rho_sj\": 0.545, \"rho_fk\": 0.646, \"rho_vc\": 0.628, \"mean_f1\": 0.513}, \"CONJUNCTION\": {\"n\": 86, \"rho_sj\": 0.383, \"rho_fk\": 0.35, \"rho_vc\": 0.484, \"mean_f1\": 0.48}, \"USED-FOR\": {\"n\": 299, \"rho_sj\": 0.236, \"rho_fk\": 0.255, \"rho_vc\": 0.286, \"mean_f1\": 0.422}, \"PART-OF\": {\"n\": 44, \"rho_sj\": 0.239, \"rho_fk\": 0.348, \"rho_vc\": 0.283, \"mean_f1\": 0.297}, \"EVALUATE-FOR\": {\"n\": 62, \"rho_sj\": 0.172, \"rho_fk\": 0.255, \"rho_vc\": 0.226, \"mean_f1\": 0.365}, \"COMPARE\": {\"n\": 35, \"rho_sj\": 0.168, \"rho_fk\": 0.184, \"rho_vc\": 0.18, \"mean_f1\": 0.453}, \"FEATURE-OF\": {\"n\": 50, \"rho_sj\": 0.004, \"rho_fk\": 0.052, \"rho_vc\": 0.014, \"mean_f1\": 0.254}}, \"error_propagation\": {\"total_fn\": 553, \"tail_error_pct\": 21.9, \"full_error_pct\": 21.7, \"head_error_pct\": 17.7, \"head_tail_error_pct\": 15.9, \"type_error_pct\": 8.3, \"worst_consistency\": \"head_type_error (sj=0.411)\", \"best_consistency\": \"head_error (sj=0.613)\"}, \"threshold_sensitivity\": {\"thr_0.00_rho_sj\": 0.3161, \"thr_0.00_rho_vc\": 0.3841, \"thr_0.00_n\": 313, \"thr_0.05_rho_sj\": 0.2682, \"thr_0.05_rho_vc\": 0.2364, \"thr_0.05_n\": 239}, \"bootstrap_ci_95\": {\"ner_sj\": [0.2946, 0.4586], \"ner_voting_conf\": [0.3048, 0.4656], \"re_sj\": [0.1422, 0.3391], \"re_voting_conf\": [0.1818, 0.3721], \"re_cond_sj\": [0.2161, 0.4102], \"re_cond_voting_conf\": [0.2825, 0.474]}, \"fisher_z_ner_vs_re\": {\"sj_z\": 2.31, \"sj_p\": 0.0209, \"sj_significant\": true, \"fk_z\": -0.31, \"fk_p\": 0.756, \"fk_significant\": false, \"voting_z\": 1.914, \"voting_p\": 0.0556, \"voting_significant\": false}, \"diagnosis\": \"FEATURE-OF is near-zero rho across all signals (n=50, F1=0.254). HYPONYM-OF strongest (rho_fk=0.646). Entity span errors (head+tail) account for 55.5% of RE FN. NER rho_sj significantly > RE rho_sj (p=0.021). Voting_conf is best RE signal in conditional set (rho=0.384).\"}}, \"exp_005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:45:16.360Z\", \"updated_at\": \"2026-05-14T11:45:38.570Z\", \"spec\": {\"hypothesis\": \"Temperature sensitivity: systematic comparison of T=0.7 vs T=1.0 on all 5 confidence signals\", \"method\": \"CPU-only analysis from checkpoint metrics (pilot_004 T=1.0, pilot_005 T=0.7, exp_012/013/014)\", \"data_count\": 551, \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2\", \"data_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/exp005_temperature/\", \"server\": \"local\", \"seed\": 42, \"parent\": \"mvp_pilot_004,mvp_pilot_005\", \"command\": \"python3 analyze_exp005_temperature.py\", \"checkpoint_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/exp005_temperature/\", \"log_path\": \"N/A\", \"checkpoint_source\": \"pilot_004+pilot_005 checkpoint metrics\", \"eval_data\": \"SciERC test set (n=551)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:45:38.570Z\"}, \"exp_014_entity_majority_voting\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:21.203Z\", \"updated_at\": \"2026-05-14T11:33:30.085Z\", \"spec\": {\"hypothesis\": \"Entity-level majority voting confidence beats SJ as correlation signal\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Per-entity voting across N=8 samples, consensus construction, confidence = mean voting rate\", \"command\": \"python code/analyze_entity_voting.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp014_entity_voting_report.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:18:09.468Z\", \"metrics\": {\"ner_full_rho\": 0.3915, \"ner_full_p\": 8.1e-21, \"ner_full_tau\": 0.2906, \"ner_full_auroc\": 0.7039, \"re_full_rho\": 0.3403, \"re_full_p\": 3.21e-12, \"re_full_tau\": 0.256, \"re_full_auroc\": 0.6668, \"ner_voting_f1\": 0.6246, \"ner_greedy_f1\": 0.6483, \"ner_oracle_f1\": 0.7793, \"re_voting_f1\": 0.3577, \"re_greedy_f1\": 0.4022, \"re_oracle_f1\": 0.5886, \"diagnosis\": \"Voting confidence BEATS SJ on both NER (rho 0.392 vs 0.383) and RE (0.340 vs 0.244). But voting as selection strategy LOSES to greedy.\"}}, \"exp_013_exact_match_voting\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:18.753Z\", \"updated_at\": \"2026-05-14T11:33:22.644Z\", \"spec\": {\"hypothesis\": \"Exact-match voting rate correlates with F1\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Count exact-match duplicates across N=8 samples\", \"command\": \"python code/analyze_exact_match_voting.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp013_exact_match_report.json\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T11:18:09.026Z\", \"metrics\": {\"ner_full_rho\": 0.2941, \"ner_full_p\": 5.12e-12, \"ner_full_tau\": 0.2181, \"ner_full_auroc\": 0.6398, \"re_full_rho\": 0.1562, \"re_full_p\": 0.0018, \"re_full_tau\": 0.1185, \"re_full_auroc\": 0.5863, \"diagnosis\": \"EM between SJ and FK on NER, weakest on RE. Too coarse-grained.\"}}, \"exp_012_logprob_baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:16.166Z\", \"updated_at\": \"2026-05-14T11:13:30.240Z\", \"spec\": {\"hypothesis\": \"Log-probability baseline: mean sequence log-prob correlates with F1 as well as or better than SJ\", \"model_name\": \"ft_002_v2 (qwen3-8b-scierc-merged-v2)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"vLLM forward pass for log-probs + Spearman rho + AUROC + Kendall tau\", \"command\": \"python3 code/extract_logprobs.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/logprob_analysis.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:06:42.542Z\", \"metrics\": {\"ner_full_rho_sj\": 0.3565, \"ner_full_rho_fk\": 0.2651, \"ner_full_rho_logprob\": 0.1396, \"ner_full_rho_greedy_logprob\": 0.1615, \"ner_full_tau_sj\": 0.2658, \"ner_full_tau_logprob\": 0.1006, \"ner_full_auroc_sj\": 0.6892, \"ner_full_auroc_fk\": 0.6292, \"ner_full_auroc_logprob\": 0.5907, \"ner_full_n\": 529, \"ner_sj_vs_logprob_delta\": 0.2169, \"re_full_rho_sj\": 0.2112, \"re_full_rho_fk\": 0.2528, \"re_full_rho_logprob\": 0.2467, \"re_full_auroc_sj\": 0.5916, \"re_full_auroc_fk\": 0.6262, \"re_full_auroc_logprob\": 0.6186, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3683, \"re_cond_rho_fk\": 0.3168, \"re_cond_rho_logprob\": 0.1457, \"re_cond_auroc_sj\": 0.6839, \"re_cond_auroc_logprob\": 0.5487, \"re_cond_n\": 296, \"diagnosis\": \"NER: SJ crushes logprob (rho +0.217). RE full: logprob slightly ahead. RE cond: SJ crushes logprob (rho +0.223). SJ unique value CONFIRMED.\"}}, \"mvp_pilot_005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:14:09.456Z\", \"updated_at\": \"2026-05-14T09:47:06.597Z\", \"spec\": {\"hypothesis\": \"T=0.7 降低 RE zero rate，恢复 SJ>FK，rho_sj 可能 ≥ 0.30 (MARGINAL threshold)\", \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2 (ft_002_v2 final)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_002_v2\", \"method\": \"N=8 sampling T=0.7 + XGrammar + span realignment + max_tokens=1024 + gold-empty filter + conditional rho\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.7 --max_tokens 1024 --output_dir output/mvp_pilot_005 --num_test 551 --seed 42 --tensor_parallel 1\", \"gpu\": \"cuda:0\", \"pid\": 32456, \"tmux_session\": \"mvp_pilot_005\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_005/train.log\"}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_005\", \"metrics\": {\"ner_greedy_f1\": 0.6619, \"ner_oracle_f1\": 0.7585, \"ner_headroom\": 0.0966, \"ner_fleiss_kappa_mean\": 0.4722, \"ner_soft_jaccard_mean\": 0.7757, \"ner_full_rho_sj\": 0.3875, \"ner_full_rho_fk\": 0.3211, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3868, \"ner_cond_rho_fk\": 0.305, \"ner_cond_n\": 504, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_rho_advantage\": 0.0664, \"ner_sample_f1_mean\": 0.6243, \"ner_sample_f1_std\": 0.3131, \"ner_sample_f1_pct_zero\": 11.2, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 25, \"re_greedy_f1\": 0.4219, \"re_oracle_f1\": 0.5532, \"re_headroom\": 0.1313, \"re_fleiss_kappa_mean\": 0.3829, \"re_soft_jaccard_mean\": 0.687, \"re_full_rho_sj\": 0.2343, \"re_full_rho_fk\": 0.1835, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3716, \"re_cond_rho_fk\": 0.2533, \"re_cond_n\": 301, \"re_sj_beats_fk_full\": true, \"re_sj_beats_fk_cond\": true, \"re_rho_advantage\": 0.0508, \"re_sample_f1_mean\": 0.3782, \"re_sample_f1_std\": 0.3845, \"re_sample_f1_pct_zero\": 42.4, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 96, \"parse_failures\": 0, \"verdict\": \"FAIL\", \"verdict_note\": \"RE full rho_sj=0.234 < 0.40; RE cond rho_sj=0.372 passes conditional but not full threshold\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T09:47:06.597Z\"}, \"e1_component_wise_re_sj\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:15:17.262Z\", \"updated_at\": \"2026-05-14T09:23:38.818Z\", \"spec\": {\"hypothesis\": \"RE SJ 乘性惩罚是 root cause：分解后 head_sj ρ ≈ NER ρ (~0.38)，tail_sj 和乘性组合拖低整体 ρ\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 397, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Component-wise decomposition: head_sj, tail_sj, type_match 分别计算 Spearman ρ vs per-instance RE F1\", \"command\": \"python3 code/analyze_component_wise_re.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/e1_component_analysis.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"full_head_sj_rho\": 0.21, \"full_tail_sj_rho\": 0.201, \"full_type_match_rho\": 0.201, \"full_multiplicative_rho\": 0.244, \"full_additive_rho\": 0.243, \"full_fleiss_kappa_rho\": 0.278, \"cond_head_sj_rho\": 0.27, \"cond_tail_sj_rho\": 0.259, \"cond_type_match_rho\": 0.252, \"cond_multiplicative_rho\": 0.316, \"cond_additive_rho\": 0.306, \"cond_fleiss_kappa_rho\": 0.307, \"n_full\": 397, \"n_conditional\": 313, \"diagnosis\": \"head_sj rho=0.210 FAR from NER rho=0.383. Multiplicative penalty hypothesis REJECTED. Problem is fundamental: span-level SJ lacks discriminative power for RE.\"}, \"completed_at\": \"2026-05-14T09:22:26.155Z\"}, \"mvp_pilot_004\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:51:38.203Z\", \"updated_at\": \"2026-05-14T09:10:40.918Z\", \"spec\": {\"hypothesis\": \"With improved RE quality (F1=41.8%), structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa, reaching rho_sj >= 0.40 on RE\", \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2 (ft_002_v2 final)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_002_v2\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment + max_tokens=1024 + gold-empty filter + conditional rho\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/mvp_pilot_004 --num_test 551 --seed 42 --tensor_parallel 1\", \"gpu\": \"cuda:0\", \"pid\": 31041, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/mvp_pilot_004.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\"}, \"metrics\": {\"ner_greedy_f1\": 0.6671, \"ner_oracle_f1\": 0.7756, \"ner_headroom\": 0.1085, \"ner_fleiss_kappa_mean\": 0.4048, \"ner_soft_jaccard_mean\": 0.7008, \"ner_full_rho_fk\": 0.259, \"ner_full_rho_sj\": 0.3825, \"ner_full_n\": 529, \"ner_cond_rho_fk\": 0.2352, \"ner_cond_rho_sj\": 0.3762, \"ner_cond_n\": 508, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_sample_f1_mean\": 0.6084, \"ner_sample_f1_std\": 0.3174, \"ner_sample_f1_pct_zero\": 12.19, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 21, \"re_greedy_f1\": 0.4208, \"re_oracle_f1\": 0.5882, \"re_headroom\": 0.1674, \"re_fleiss_kappa_mean\": 0.2996, \"re_soft_jaccard_mean\": 0.6114, \"re_full_rho_fk\": 0.2782, \"re_full_rho_sj\": 0.2441, \"re_full_n\": 397, \"re_cond_rho_fk\": 0.3067, \"re_cond_rho_sj\": 0.3161, \"re_cond_n\": 313, \"re_sj_beats_fk_full\": false, \"re_sj_beats_fk_cond\": true, \"re_sample_f1_mean\": 0.3612, \"re_sample_f1_std\": 0.383, \"re_sample_f1_pct_zero\": 44.3, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 84, \"parse_failures\": 0, \"verdict\": \"FAIL\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T09:10:40.918Z\"}, \"ft_002_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:28:40.861Z\", \"updated_at\": \"2026-05-14T08:51:32.405Z\", \"spec\": {\"hypothesis\": \"Extended training (5 epochs, LoRA r=32) with OOM fix improves RE F1 above 40% threshold\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/llmfactory_train.json\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"LoRA r=32 alpha=64, 5 epochs, batch=2 grad_accum=8 gradient_checkpointing=true\", \"gpu\": \"cuda:1\", \"pid\": 24947, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/ft_002v2_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora-v2\", \"command\": \"CUDA_VISIBLE_DEVICES=1 llamafactory-cli train train_config_v2.yaml\"}, \"conclusion\": \"success\", \"metrics\": {\"epoch\": 5, \"train_loss\": 0.0806, \"eval_loss\": 0.089, \"train_runtime\": \"28m41s\", \"train_samples_per_second\": 5.407, \"train_steps_per_second\": 0.34, \"total_steps\": 585, \"checkpoints\": [\"checkpoint-400\", \"checkpoint-500\", \"checkpoint-585\"], \"gate0_final_ner_f1\": 0.6615, \"gate0_final_re_f1\": 0.4177, \"gate0_final_parse_failures\": 0, \"gate0_final_ner_pass\": true, \"gate0_final_re_pass\": true, \"gate0_final_pass\": true, \"gate0_ckpt400_ner_f1\": 0.6475, \"gate0_ckpt400_re_f1\": 0.3793, \"gate0_ckpt400_parse_failures\": 0, \"gate0_ckpt400_verdict\": \"FAIL\", \"gate0_ckpt400_re_sample_f1_pct_zero\": 58.8, \"gate0_ckpt400_warning\": \">30% samples F1=0\"}, \"completed_at\": \"2026-05-14T08:51:32.405Z\"}, \"mvp_pilot_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:02:16.991Z\", \"updated_at\": \"2026-05-14T08:48:14.040Z\", \"spec\": {\"hypothesis\": \"Structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa on fine-tuned Qwen3-8B SciERC\", \"model_name\": \"Qwen3-8B-SciERC-LoRA (ft_001)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment + gold-empty filter + conditional rho\", \"gpu\": \"cuda:0\", \"note\": \"Rerun of mvp_pilot_001 which crashed silently\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-lora --data_dir data/scierc --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 512 --output_dir output/mvp_pilot_001 --num_test 551 --seed 42 --tensor_parallel 1\", \"failure_reason\": \"Worker used LoRA adapter path instead of merged model path; vLLM cannot load LoRA adapter directly\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T08:48:14.040Z\"}, \"ft_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:39:18.640Z\", \"updated_at\": \"2026-05-14T08:28:00.590Z\", \"spec\": {\"hypothesis\": \"Extended training (5 epochs, LoRA r=32) improves RE F1 above 40% threshold\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/llmfactory_train.json\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"LoRA r=32 alpha=64, 5 epochs, relation direction hint\", \"command\": \"llamafactory-cli train /root/autodl-tmp/struct_self_consist_ie/train_config_v2.yaml\", \"gpu\": \"cuda:1\", \"pid\": 19666, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/ft_002_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora-v2\", \"total_steps\": 585, \"trainable_params\": \"87.3M\", \"estimated_runtime\": \"29min\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T08:02:30.390Z\", \"metrics\": {\"last_step\": 70, \"total_steps\": 585, \"progress_pct\": 11.97, \"last_loss\": 0.1134, \"last_lr\": 0.00019982, \"elapsed\": \"3m32s\", \"failure_reason\": \"OOM at step 73, batch_size=4 too large for 32GB RTX 5090\"}}, \"ft_001\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T06:04:28.030Z\", \"updated_at\": \"2026-05-14T08:27:58.182Z\", \"spec\": {\"hypothesis\": \"Fine-tuned Qwen3-8B on SciERC UIE can achieve NER F1 >= 73 and serve as base model for structural consistency MVP\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"method\": \"LoRA r=16 alpha=32\", \"framework\": \"LLaMA Factory 0.9.4\", \"command\": \"sft training qwen3-8b on scierc with lora\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/ft_001_train.log\", \"train_loss\": 0.1099, \"eval_loss\": 0.0771, \"epoch\": 3, \"train_runtime\": \"0:17:49\", \"note\": \"gate0: NER PASS 60.4% / RE FAIL 33.8%\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T06:30:32.889Z\", \"metrics\": {\"train_loss\": 0.1099, \"eval_loss\": 0.0771, \"gate0_ner_f1_strict\": 0.1143, \"gate0_re_f1_strict\": 0.0125, \"gate0_ner_f1_text\": 0.606, \"gate0_re_f1_text\": 0.3392, \"gate0_offset_accuracy\": 0.1665, \"gate0_parse_failures\": 43, \"gate0_pass\": false, \"gate0_realigned_ner_f1\": 0.6045, \"gate0_realigned_re_f1\": 0.338, \"gate0_realigned_entity_offset_accuracy\": 1, \"gate0_realigned_relation_offset_accuracy\": 1, \"gate0_realigned_ner_pass\": true, \"gate0_realigned_re_pass\": false, \"gate0_realigned_pass\": false, \"gate0_ner_f1_delta_realign\": 0.4901, \"gate0_re_f1_delta_realign\": 0.3255, \"verdict_note\": \"partial: NER PASS (60.4%) / RE FAIL (33.8% < 40%)\"}}, \"mvp_pilot_003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:21:09.847Z\", \"updated_at\": \"2026-05-14T08:21:44.983Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path /root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged --data_dir /root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir /root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_003 --num_test 551 --seed 42 --tensor_parallel 1\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged\", \"seed\": 42}, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/mvp_pilot_003.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_003\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T08:21:30.319Z\", \"metrics\": {\"ner_greedy_f1\": 0.6362, \"ner_oracle_f1\": 0.792, \"ner_headroom\": 0.1559, \"ner_fleiss_kappa_mean\": 0.2488, \"ner_soft_jaccard_mean\": 0.5066, \"ner_full_rho_sj\": 0.3808, \"ner_full_rho_fk\": 0.3362, \"ner_full_p_sj\": 1.07e-19, \"ner_full_p_fk\": 1.93e-15, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3836, \"ner_cond_rho_fk\": 0.3187, \"ner_cond_p_sj\": 1.83e-19, \"ner_cond_p_fk\": 1.33e-13, \"ner_cond_n\": 514, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_rho_advantage\": 0.0446, \"ner_sample_f1_mean\": 0.5153, \"ner_sample_f1_std\": 0.3334, \"ner_sample_f1_pct_zero\": 19.9, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 15, \"re_greedy_f1\": 0.3774, \"re_oracle_f1\": 0.5939, \"re_headroom\": 0.2165, \"re_fleiss_kappa_mean\": 0.0879, \"re_soft_jaccard_mean\": 0.3958, \"re_full_rho_sj\": 0.2367, \"re_full_rho_fk\": 0.2221, \"re_full_p_sj\": 1.85e-06, \"re_full_p_fk\": 7.92e-06, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3004, \"re_cond_rho_fk\": 0.2374, \"re_cond_p_sj\": 2.25e-08, \"re_cond_p_fk\": 1.19e-05, \"re_cond_n\": 333, \"re_sj_beats_fk_full\": true, \"re_sj_beats_fk_cond\": true, \"re_rho_advantage\": 0.0146, \"re_sample_f1_mean\": 0.1977, \"re_sample_f1_std\": 0.3251, \"re_sample_f1_pct_zero\": 67.6, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 64, \"parse_failures_stochastic\": 0, \"parse_failures_greedy\": 0, \"total_stochastic_samples\": 4408, \"total_greedy\": 551, \"verdict\": \"FAIL\", \"verdict_reason\": \"RE full rho_sj=0.2367 < 0.40 threshold; strong signal exists but below PASS bar\"}}, \"mvp_pilot_001\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:39:16.313Z\", \"updated_at\": \"2026-05-14T08:05:34.348Z\", \"spec\": {\"hypothesis\": \"Structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa on fine-tuned Qwen3-8B SciERC\", \"model_name\": \"qwen3-8b-scierc-merged\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/test.jsonl\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/mvp_pilot.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_001.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T07:52:47.006Z\", \"metrics\": {\"ner_greedy_f1\": 0.611, \"ner_oracle_f1\": 0.78, \"ner_headroom\": 0.169, \"ner_fleiss_kappa_mean\": 0.2449, \"ner_soft_jaccard_mean\": 0.5041, \"ner_full_rho_sj\": 0.3616, \"ner_full_rho_fk\": 0.3515, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3688, \"ner_cond_rho_fk\": 0.3569, \"ner_cond_n\": 510, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_sample_f1_pct_zero\": 20.4, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 19, \"re_greedy_f1\": 0.355, \"re_oracle_f1\": 0.572, \"re_headroom\": 0.217, \"re_fleiss_kappa_mean\": 0.0681, \"re_soft_jaccard_mean\": 0.3635, \"re_full_rho_sj\": 0.2535, \"re_full_rho_fk\": 0.2885, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3515, \"re_cond_rho_fk\": 0.3107, \"re_cond_n\": 320, \"re_sj_beats_fk_full\": false, \"re_sj_beats_fk_cond\": true, \"re_sample_f1_pct_zero\": 58.3, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 77, \"parse_failures_stochastic\": 164, \"parse_failures_greedy\": 29, \"total_stochastic_samples\": 4408, \"total_greedy\": 551, \"verdict\": \"FAIL\", \"verdict_reason\": \"RE full rho_sj=0.2535 < 0.40; SJ does not beat FK on RE full set\"}}}, \"count\": 257, \"total\": 257, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.8066}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-21T12:00:27.292Z_

<details><summary>↩ Tool result · `toolu_01ML6JcnxbZVuGGnnV1tAe8N`</summary>

```text
artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/alpha.py
artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/__pycache__/alpha.cpython-314.pyc
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/alpha.py
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/__pycache__/alpha.cpython-314.pyc
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/alpha.py
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/__pycache__/alpha.cpython-314.pyc
artifacts/_project/report/alpha_crit_table.md
logs/workers/worker_cpu_alpha_crit_derivation_20260521T071446.log
logs/chats/worker_cpu_alpha_crit_derivation_20260521T071446.lock
logs/chats/worker_cpu_alpha_crit_derivation_20260521T071446.jsonl
logs/workers/worker_cpu_alpha_crit_derivation_20260521T071446_result.json
artifacts/_project/report/alpha_crit_table_65652e.md
artifacts/_project/data/alpha_crit_table.md
logs/workers/worker_cpu_alpha_crit_seed_audit_20260521T092648.log
logs/chats/worker_cpu_alpha_crit_seed_audit_20260521T092648.lock
logs/chats/worker_cpu_alpha_crit_seed_audit_20260521T092648.jsonl
logs/workers/worker_cpu_alpha_crit_seed_audit_20260521T092648_result.json
artifacts/_project/report/alpha_crit_table_1d6921.md
logs/workers/worker_cpu_alpha_crit_v3_micro_f1_20260521T094702.log
logs/chats/worker_cpu_alpha_crit_v3_micro_f1_20260521T094702.lock
logs/chats/worker_cpu_alpha_crit_v3_micro_f1_20260521T094702.jsonl
logs/workers/worker_cpu_alpha_crit_v3_micro_f1_20260521T094702_result.json
logs/workers/worker_ssh_alpha_crit_conll_s42_gemini_20260521T111401.log
logs/workers/worker_ssh_alpha_crit_conll_s42_gemini_20260521T111401_result.json
artifacts/alpha_crit_table.md
logs/workers/worker_research_alpha_crit_derivation_20260521T113132.log
logs/workers/worker_research_alpha_crit_derivation_20260521T113132_result.json
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "38d5bac1-f281-4241-8dab-dc9cabe92712",
  "tool_use_result": {
    "filenames": [
      "artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/alpha.py",
      "artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/__pycache__/alpha.cpython-314.pyc",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/alpha.py",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/__pycache__/alpha.cpython-314.pyc",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/alpha.py",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/openai/resources/fine_tuning/alpha/__pycache__/alpha.cpython-314.pyc",
      "artifacts/_project/report/alpha_crit_table.md",
      "logs/workers/worker_cpu_alpha_crit_derivation_20260521T071446.log",
      "logs/chats/worker_cpu_alpha_crit_derivation_20260521T071446.lock",
      "logs/chats/worker_cpu_alpha_crit_derivation_20260521T071446.jsonl",
      "logs/workers/worker_cpu_alpha_crit_derivation_20260521T071446_result.json",
      "artifacts/_project/report/alpha_crit_table_65652e.md",
      "artifacts/_project/data/alpha_crit_table.md",
      "logs/workers/worker_cpu_alpha_crit_seed_audit_20260521T092648.log",
      "logs/chats/worker_cpu_alpha_crit_seed_audit_20260521T092648.lock",
      "logs/chats/worker_cpu_alpha_crit_seed_audit_20260521T092648.jsonl",
      "logs/workers/worker_cpu_alpha_crit_seed_audit_20260521T092648_result.json",
      "artifacts/_project/report/alpha_crit_table_1d6921.md",
      "logs/workers/worker_cpu_alpha_crit_v3_micro_f1_20260521T094702.log",
      "logs/chats/worker_cpu_alpha_crit_v3_micro_f1_20260521T094702.lock",
      "logs/chats/worker_cpu_alpha_crit_v3_micro_f1_20260521T094702.jsonl",
      "logs/workers/worker_cpu_alpha_crit_v3_micro_f1_20260521T094702_result.json",
      "logs/workers/worker_ssh_alpha_crit_conll_s42_gemini_20260521T111401.log",
      "logs/workers/worker_ssh_alpha_crit_conll_s42_gemini_20260521T111401_result.json",
      "artifacts/alpha_crit_table.md",
      "logs/workers/worker_research_alpha_crit_derivation_20260521T113132.log",
      "logs/workers/worker_research_alpha_crit_derivation_20260521T113132_result.json"
    ],
    "durationMs": 111,
    "numFiles": 27,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 15_

<details open><summary>🔧 Tool call — Glob · `toolu_018SaqCaMiY8F1xP7y2w6Ax9`</summary>

```json
{
  "pattern": "**/*rho*",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "f786802b-7f37-41ad-a444-047f9710641b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A4jCnd8Nv8q6AJUcLU42WM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 800,
      "cache_read_input_tokens": 23806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 800
      },
      "output_tokens": 30,
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

_source line 16 · 2026-05-21T12:00:27.497Z_

<details><summary>↩ Tool result · `toolu_018SaqCaMiY8F1xP7y2w6Ax9`</summary>

```text
artifacts/_project/report/logprob_rho_diagnosis.md
logs/workers/worker_analysis_logprob_rho_inconsistency_20260514T122249.log
logs/chats/worker_analysis_logprob_rho_inconsistency_20260514T122249.lock
logs/chats/worker_analysis_logprob_rho_inconsistency_20260514T122249.jsonl
logs/workers/worker_analysis_logprob_rho_inconsistency_20260514T122249_result.json
.venv/lib/python3.14/site-packages/numpy/_core/include/numpy/_neighborhood_iterator_imp.h
.venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/redrho.py
.venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/__pycache__/redrho.cpython-314.pyc
artifacts/_project/report/vc_implementation_rho_diff.md
artifacts/vc_implementation_rho_diff.md
logs/workers/worker_analysis_d070_vc_rho_diff_20260515T091741.log
logs/workers/worker_analysis_d070_vc_rho_diff_20260515T091741_result.json
artifacts/_project/report/rho_consistency_audit.md
artifacts/_project/report/rho_consistency_audit_2afe55.md
artifacts/rho_consistency_audit.md
artifacts/_project/data/analysis_unified_rho_2fa4eb.json
artifacts/_project/data/analysis_unified_rho.json
artifacts/analysis_unified_rho.json
logs/workers/worker_analysis_rho_consistency_audit_20260515T131810.log
logs/workers/worker_analysis_rho_consistency_audit_20260515T131810_result.json
artifacts/_project/report/rho_paper_impact_list.md
artifacts/rho_paper_impact_list.md
logs/workers/worker_analysis_rho_paper_impact_list_20260515T132710.log
logs/workers/worker_analysis_rho_paper_impact_list_20260515T132710_result.json
logs/workers/worker_analysis_unified_rho_n8_seed123_20260515T133720.log
logs/workers/worker_analysis_unified_rho_n8_seed123_20260515T133720_result.json
logs/workers/worker_analysis_unified_rho_n8_seed123_20260515T145442.log
logs/workers/worker_analysis_unified_rho_n8_seed123_20260515T145442_result.json
logs/workers/worker_analysis_n8_seed123_unified_rho_20260515T145640.log
logs/workers/worker_analysis_n8_seed123_unified_rho_20260515T145640_result.json
logs/workers/worker_analysis_lp_full_vs_cond_rho_20260515T160119.log
logs/workers/worker_analysis_lp_full_vs_cond_rho_20260515T160119_result.json
logs/workers/worker_analysis_fk_rho_inconsistency_20260515T155957.log
logs/workers/worker_analysis_fk_rho_inconsistency_20260515T155957_result.json
artifacts/_project/data/analysis_unified_rho_full_0da660.json
artifacts/_project/data/analysis_unified_rho_full_dff588.json
artifacts/analysis_unified_rho_full.json
artifacts/_project/data/analysis_unified_rho_full.json
artifacts/n8_seed123_unified_rho_results.md
artifacts/_project/report/n8_seed123_unified_rho_results.md
logs/workers/worker_analysis_table1_vs_table4_rho_discrepancy_20260515T235236.log
logs/workers/worker_analysis_table1_vs_table4_rho_discrepancy_20260515T235236_result.json
artifacts/_project/data/d108_mbr_within_instance_rho.txt
logs/workers/worker_analysis_d108_mbr_within_rho_20260516T070432.log
logs/chats/worker_analysis_d108_mbr_within_rho_20260516T070432.lock
logs/chats/worker_analysis_d108_mbr_within_rho_20260516T070432.jsonl
logs/workers/worker_analysis_d108_mbr_within_rho_20260516T070432_result.json
logs/workers/worker_analysis_r17_p2_within_sj_rho_and_confounds_20260517T075432.log
logs/workers/worker_analysis_r17_p2_within_sj_rho_and_confounds_20260517T075432_result.json
artifacts/exp_026_T_ablation/within_instance_rho.json
logs/workers/worker_analysis_exp_026_degeneracy_and_within_rho_20260517T100239.log
logs/workers/worker_analysis_exp_026_degeneracy_and_within_rho_20260517T100239_result.json
logs/workers/worker_analysis_exp021_within_rho_20260517T203007.log
logs/workers/worker_analysis_exp021_within_rho_20260517T203007_result.json
logs/workers/worker_analysis_r21_w5_lp_rho_audit_20260518T133538.log
logs/chats/worker_analysis_r21_w5_lp_rho_audit_20260518T133538.lock
logs/chats/worker_analysis_r21_w5_lp_rho_audit_20260518T133538.jsonl
logs/workers/worker_analysis_r21_w5_lp_rho_audit_20260518T133538_result.json
artifacts/_project/report/q1_within_instance_rho_35e285.md
artifacts/_project/report/q1_within_instance_rho.md
artifacts/p1_review_computations/q1_within_instance_rho.md
artifacts/_project/report/w5_lp_rho_audit.md
artifacts/p1_review_computations/w5_lp_rho_audit.md
artifacts/_project/report/epoch_scierc_text_based_rho_b340c0.md
artifacts/_project/report/epoch_scierc_text_based_rho.md
artifacts/d146_epoch_scierc_rho/epoch_scierc_text_based_rho.md
logs/workers/worker_analysis_epoch_scierc_rho_text_based_20260518T145948.log
logs/workers/worker_analysis_epoch_scierc_rho_text_based_20260518T145948_result.json
logs/workers/worker_analysis_lp_rho_inconsistency_p0_20260518T232334.log
logs/workers/worker_analysis_lp_rho_inconsistency_p0_20260518T232334_result.json
logs/workers/worker_analysis_fig_overview_and_vc_rho_20260518T233414.log
logs/workers/worker_analysis_fig_overview_and_vc_rho_20260518T233414_result.json
logs/workers/worker_analysis_abstract_rho_context_20260519T112114.log
logs/workers/worker_analysis_abstract_rho_context_20260519T112114_result.json
artifacts/scaling_signal_rho.pdf
artifacts/scaling_signal_rho.png
artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/numpy/_core/include/numpy/_neighborhood_iterator_imp.h
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/numpy/_core/include/numpy/_neighborhood_iterator_imp.h
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/redrho.py
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/__pycache__/redrho.cpython-314.pyc
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/numpy/_core/include/numpy/_neighborhood_iterator_imp.h
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/redrho.py
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/__pycache__/redrho.cpython-314.pyc
logs/workers/worker_cpu_rho_max_verify_20260521T120007.log
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "489b70a8-04ff-44d2-bbf7-96968da8b62c",
  "tool_use_result": {
    "filenames": [
      "artifacts/_project/report/logprob_rho_diagnosis.md",
      "logs/workers/worker_analysis_logprob_rho_inconsistency_20260514T122249.log",
      "logs/chats/worker_analysis_logprob_rho_inconsistency_20260514T122249.lock",
      "logs/chats/worker_analysis_logprob_rho_inconsistency_20260514T122249.jsonl",
      "logs/workers/worker_analysis_logprob_rho_inconsistency_20260514T122249_result.json",
      ".venv/lib/python3.14/site-packages/numpy/_core/include/numpy/_neighborhood_iterator_imp.h",
      ".venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/redrho.py",
      ".venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/__pycache__/redrho.cpython-314.pyc",
      "artifacts/_project/report/vc_implementation_rho_diff.md",
      "artifacts/vc_implementation_rho_diff.md",
      "logs/workers/worker_analysis_d070_vc_rho_diff_20260515T091741.log",
      "logs/workers/worker_analysis_d070_vc_rho_diff_20260515T091741_result.json",
      "artifacts/_project/report/rho_consistency_audit.md",
      "artifacts/_project/report/rho_consistency_audit_2afe55.md",
      "artifacts/rho_consistency_audit.md",
      "artifacts/_project/data/analysis_unified_rho_2fa4eb.json",
      "artifacts/_project/data/analysis_unified_rho.json",
      "artifacts/analysis_unified_rho.json",
      "logs/workers/worker_analysis_rho_consistency_audit_20260515T131810.log",
      "logs/workers/worker_analysis_rho_consistency_audit_20260515T131810_result.json",
      "artifacts/_project/report/rho_paper_impact_list.md",
      "artifacts/rho_paper_impact_list.md",
      "logs/workers/worker_analysis_rho_paper_impact_list_20260515T132710.log",
      "logs/workers/worker_analysis_rho_paper_impact_list_20260515T132710_result.json",
      "logs/workers/worker_analysis_unified_rho_n8_seed123_20260515T133720.log",
      "logs/workers/worker_analysis_unified_rho_n8_seed123_20260515T133720_result.json",
      "logs/workers/worker_analysis_unified_rho_n8_seed123_20260515T145442.log",
      "logs/workers/worker_analysis_unified_rho_n8_seed123_20260515T145442_result.json",
      "logs/workers/worker_analysis_n8_seed123_unified_rho_20260515T145640.log",
      "logs/workers/worker_analysis_n8_seed123_unified_rho_20260515T145640_result.json",
      "logs/workers/worker_analysis_lp_full_vs_cond_rho_20260515T160119.log",
      "logs/workers/worker_analysis_lp_full_vs_cond_rho_20260515T160119_result.json",
      "logs/workers/worker_analysis_fk_rho_inconsistency_20260515T155957.log",
      "logs/workers/worker_analysis_fk_rho_inconsistency_20260515T155957_result.json",
      "artifacts/_project/data/analysis_unified_rho_full_0da660.json",
      "artifacts/_project/data/analysis_unified_rho_full_dff588.json",
      "artifacts/analysis_unified_rho_full.json",
      "artifacts/_project/data/analysis_unified_rho_full.json",
      "artifacts/n8_seed123_unified_rho_results.md",
      "artifacts/_project/report/n8_seed123_unified_rho_results.md",
      "logs/workers/worker_analysis_table1_vs_table4_rho_discrepancy_20260515T235236.log",
      "logs/workers/worker_analysis_table1_vs_table4_rho_discrepancy_20260515T235236_result.json",
      "artifacts/_project/data/d108_mbr_within_instance_rho.txt",
      "logs/workers/worker_analysis_d108_mbr_within_rho_20260516T070432.log",
      "logs/chats/worker_analysis_d108_mbr_within_rho_20260516T070432.lock",
      "logs/chats/worker_analysis_d108_mbr_within_rho_20260516T070432.jsonl",
      "logs/workers/worker_analysis_d108_mbr_within_rho_20260516T070432_result.json",
      "logs/workers/worker_analysis_r17_p2_within_sj_rho_and_confounds_20260517T075432.log",
      "logs/workers/worker_analysis_r17_p2_within_sj_rho_and_confounds_20260517T075432_result.json",
      "artifacts/exp_026_T_ablation/within_instance_rho.json",
      "logs/workers/worker_analysis_exp_026_degeneracy_and_within_rho_20260517T100239.log",
      "logs/workers/worker_analysis_exp_026_degeneracy_and_within_rho_20260517T100239_result.json",
      "logs/workers/worker_analysis_exp021_within_rho_20260517T203007.log",
      "logs/workers/worker_analysis_exp021_within_rho_20260517T203007_result.json",
      "logs/workers/worker_analysis_r21_w5_lp_rho_audit_20260518T133538.log",
      "logs/chats/worker_analysis_r21_w5_lp_rho_audit_20260518T133538.lock",
      "logs/chats/worker_analysis_r21_w5_lp_rho_audit_20260518T133538.jsonl",
      "logs/workers/worker_analysis_r21_w5_lp_rho_audit_20260518T133538_result.json",
      "artifacts/_project/report/q1_within_instance_rho_35e285.md",
      "artifacts/_project/report/q1_within_instance_rho.md",
      "artifacts/p1_review_computations/q1_within_instance_rho.md",
      "artifacts/_project/report/w5_lp_rho_audit.md",
      "artifacts/p1_review_computations/w5_lp_rho_audit.md",
      "artifacts/_project/report/epoch_scierc_text_based_rho_b340c0.md",
      "artifacts/_project/report/epoch_scierc_text_based_rho.md",
      "artifacts/d146_epoch_scierc_rho/epoch_scierc_text_based_rho.md",
      "logs/workers/worker_analysis_epoch_scierc_rho_text_based_20260518T145948.log",
      "logs/workers/worker_analysis_epoch_scierc_rho_text_based_20260518T145948_result.json",
      "logs/workers/worker_analysis_lp_rho_inconsistency_p0_20260518T232334.log",
      "logs/workers/worker_analysis_lp_rho_inconsistency_p0_20260518T232334_result.json",
      "logs/workers/worker_analysis_fig_overview_and_vc_rho_20260518T233414.log",
      "logs/workers/worker_analysis_fig_overview_and_vc_rho_20260518T233414_result.json",
      "logs/workers/worker_analysis_abstract_rho_context_20260519T112114.log",
      "logs/workers/worker_analysis_abstract_rho_context_20260519T112114_result.json",
      "artifacts/scaling_signal_rho.pdf",
      "artifacts/scaling_signal_rho.png",
      "artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/numpy/_core/include/numpy/_neighborhood_iterator_imp.h",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/numpy/_core/include/numpy/_neighborhood_iterator_imp.h",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/redrho.py",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/__pycache__/redrho.cpython-314.pyc",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/numpy/_core/include/numpy/_neighborhood_iterator_imp.h",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/redrho.py",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/_lib/pyprima/common/__pycache__/redrho.cpython-314.pyc",
      "logs/workers/worker_cpu_rho_max_verify_20260521T120007.log"
    ],
    "durationMs": 108,
    "numFiles": 84,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 17_

<details open><summary>🔧 Tool call — Glob · `toolu_01Sbe39JpG4Fj1y7jPMQW6RS`</summary>

```json
{
  "pattern": "**/*corr*",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "4c7d85d6-db5b-4623-bddb-563b6df8622d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A4jCnd8Nv8q6AJUcLU42WM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 800,
      "cache_read_input_tokens": 23806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 800
      },
      "output_tokens": 30,
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

_source line 18 · 2026-05-21T12:00:27.680Z_

<details><summary>↩ Tool result · `toolu_01Sbe39JpG4Fj1y7jPMQW6RS`</summary>

```text
artifacts/exp_016_signal_ensemble/data/correlation_matrix.json
artifacts/exp_016_signal_ensemble/report/correlation_matrix.json
artifacts/exp-001/report/corrected_conditional_metrics.json
artifacts/exp_001/data/corrected_conditional_metrics_ref.txt
artifacts/_project/chart/fig_correlation_selection_gap.pdf
artifacts/figures/fig_correlation_selection_gap.pdf
artifacts/figures/fig_correlation_selection_gap.png
.venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_checksum.mat
.venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_data.mat
.venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml-iris.txt
.venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml.txt
.venv/lib/python3.14/site-packages/scipy/stats/_correlation.py
.venv/lib/python3.14/site-packages/scipy/stats/tests/test_correlation.py
.venv/lib/python3.14/site-packages/scipy/stats/__pycache__/_correlation.cpython-314.pyc
.venv/lib/python3.14/site-packages/scipy/stats/tests/__pycache__/test_correlation.cpython-314.pyc
logs/workers/worker_research_consistency_vs_correctness_lit_20260516T220603.log
logs/workers/worker_research_consistency_vs_correctness_lit_20260516T220603_result.json
logs/workers/worker_analysis_degeneracy_lp_scatter_and_corr_20260517T044343.log
logs/workers/worker_analysis_degeneracy_lp_scatter_and_corr_20260517T044343_result.json
logs/workers/worker_paper-fix_auroc_correction_20260519T141908.log
logs/workers/worker_paper-fix_degen_rate_correction_20260519T142219.log
logs/workers/worker_paper-fix_degen_rate_correction_20260519T142219_result.json
artifacts/compute_error_correlation.py
artifacts/exp_qwen25_72b_fewshot/data/fs_vs_zs_error_correlation.json
artifacts/fs_vs_zs_error_correlation.json
logs/workers/worker_code_fs-vs-zs-error-correlation_20260520T013711.log
logs/workers/worker_code_fs-vs-zs-error-correlation_20260520T013711_result.json
logs/workers/worker_knowledge_memory-error-correlation-update_20260520T014242.log
logs/workers/worker_knowledge_memory-error-correlation-update_20260520T014242_result.json
logs/workers/worker_knowledge_memory-error-correlation-update_20260520T014418.log
logs/workers/worker_knowledge_memory-error-correlation-update_20260520T014418_result.json
logs/workers/worker_ssh_verify-7b-fk-correct-data_20260520T081620.log
logs/chats/worker_ssh_verify-7b-fk-correct-data_20260520T081620.lock
logs/chats/worker_ssh_verify-7b-fk-correct-data_20260520T081620.jsonl
logs/workers/worker_ssh_verify-7b-fk-correct-data_20260520T081620_result.json
artifacts/_project/data/corrected_pvalues.json
artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/test_cov_corr.py
artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_autocorr.py
artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_cov_corr.py
artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/__pycache__/test_cov_corr.cpython-314.pyc
artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_autocorr.cpython-314.pyc
artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_cov_corr.cpython-314.pyc
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_checksum.mat
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_data.mat
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml-iris.txt
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml.txt
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/stats/_correlation.py
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/stats/tests/test_correlation.py
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/stats/__pycache__/_correlation.cpython-314.pyc
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/stats/tests/__pycache__/test_correlation.cpython-314.pyc
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/test_cov_corr.py
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_autocorr.py
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_cov_corr.py
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/__pycache__/test_cov_corr.cpython-314.pyc
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_autocorr.cpython-314.pyc
artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_cov_corr.cpython-314.pyc
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_checksum.mat
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_data.mat
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml-iris.txt
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml.txt
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/stats/_correlation.py
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/stats/tests/test_correlation.py
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/stats/__pycache__/_correlation.cpython-314.pyc
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/stats/tests/__pycache__/test_correlation.cpython-314.pyc
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/test_cov_corr.py
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_autocorr.py
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_cov_corr.py
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/__pycache__/test_cov_corr.cpython-314.pyc
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_autocorr.cpython-314.pyc
artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_cov_corr.cpython-314.pyc
artifacts/multi_model_error_correlation.py
artifacts/exp_multi_model_correlation/report/multi_model_error_correlation.py
checkpoints/exp_multi_model_correlation_QUEUED_20260521T020435.json
checkpoints/exp_multi_model_correlation_RUNNING_20260521T020441.json
checkpoints/exp_multi_model_correlation_RUNNING_20260521T020500.json
checkpoints/exp_multi_model_correlation_DONE_20260521T020505.json
logs/workers/worker_analysis_multi_model_error_correlation_20260521T015715.log
logs/chats/worker_analysis_multi_model_error_correlation_20260521T015715.lock
logs/chats/worker_analysis_multi_model_error_correlation_20260521T015715.jsonl
logs/workers/worker_analysis_multi_model_error_correlation_20260521T015715_result.json
artifacts/_project/report/d220_correction_notes.md
artifacts/_project/report/d220_correction_notes_4e5dea.md
artifacts/d220_correction_notes.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "b93ea5f0-95de-476d-97e9-32bd2be96554",
  "tool_use_result": {
    "filenames": [
      "artifacts/exp_016_signal_ensemble/data/correlation_matrix.json",
      "artifacts/exp_016_signal_ensemble/report/correlation_matrix.json",
      "artifacts/exp-001/report/corrected_conditional_metrics.json",
      "artifacts/exp_001/data/corrected_conditional_metrics_ref.txt",
      "artifacts/_project/chart/fig_correlation_selection_gap.pdf",
      "artifacts/figures/fig_correlation_selection_gap.pdf",
      "artifacts/figures/fig_correlation_selection_gap.png",
      ".venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_checksum.mat",
      ".venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_data.mat",
      ".venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml-iris.txt",
      ".venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml.txt",
      ".venv/lib/python3.14/site-packages/scipy/stats/_correlation.py",
      ".venv/lib/python3.14/site-packages/scipy/stats/tests/test_correlation.py",
      ".venv/lib/python3.14/site-packages/scipy/stats/__pycache__/_correlation.cpython-314.pyc",
      ".venv/lib/python3.14/site-packages/scipy/stats/tests/__pycache__/test_correlation.cpython-314.pyc",
      "logs/workers/worker_research_consistency_vs_correctness_lit_20260516T220603.log",
      "logs/workers/worker_research_consistency_vs_correctness_lit_20260516T220603_result.json",
      "logs/workers/worker_analysis_degeneracy_lp_scatter_and_corr_20260517T044343.log",
      "logs/workers/worker_analysis_degeneracy_lp_scatter_and_corr_20260517T044343_result.json",
      "logs/workers/worker_paper-fix_auroc_correction_20260519T141908.log",
      "logs/workers/worker_paper-fix_degen_rate_correction_20260519T142219.log",
      "logs/workers/worker_paper-fix_degen_rate_correction_20260519T142219_result.json",
      "artifacts/compute_error_correlation.py",
      "artifacts/exp_qwen25_72b_fewshot/data/fs_vs_zs_error_correlation.json",
      "artifacts/fs_vs_zs_error_correlation.json",
      "logs/workers/worker_code_fs-vs-zs-error-correlation_20260520T013711.log",
      "logs/workers/worker_code_fs-vs-zs-error-correlation_20260520T013711_result.json",
      "logs/workers/worker_knowledge_memory-error-correlation-update_20260520T014242.log",
      "logs/workers/worker_knowledge_memory-error-correlation-update_20260520T014242_result.json",
      "logs/workers/worker_knowledge_memory-error-correlation-update_20260520T014418.log",
      "logs/workers/worker_knowledge_memory-error-correlation-update_20260520T014418_result.json",
      "logs/workers/worker_ssh_verify-7b-fk-correct-data_20260520T081620.log",
      "logs/chats/worker_ssh_verify-7b-fk-correct-data_20260520T081620.lock",
      "logs/chats/worker_ssh_verify-7b-fk-correct-data_20260520T081620.jsonl",
      "logs/workers/worker_ssh_verify-7b-fk-correct-data_20260520T081620_result.json",
      "artifacts/_project/data/corrected_pvalues.json",
      "artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/test_cov_corr.py",
      "artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_autocorr.py",
      "artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_cov_corr.py",
      "artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/__pycache__/test_cov_corr.cpython-314.pyc",
      "artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_autocorr.cpython-314.pyc",
      "artifacts/experiments/humaneval_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_cov_corr.cpython-314.pyc",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_checksum.mat",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_data.mat",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml-iris.txt",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml.txt",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/stats/_correlation.py",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/stats/tests/test_correlation.py",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/stats/__pycache__/_correlation.cpython-314.pyc",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/scipy/stats/tests/__pycache__/test_correlation.cpython-314.pyc",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/test_cov_corr.py",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_autocorr.py",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_cov_corr.py",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/__pycache__/test_cov_corr.cpython-314.pyc",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_autocorr.cpython-314.pyc",
      "artifacts/experiments/frontier_sc/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_cov_corr.cpython-314.pyc",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_checksum.mat",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/io/matlab/tests/data/corrupted_zlib_data.mat",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml-iris.txt",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/spatial/tests/data/pdist-correlation-ml.txt",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/stats/_correlation.py",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/stats/tests/test_correlation.py",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/stats/__pycache__/_correlation.cpython-314.pyc",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/scipy/stats/tests/__pycache__/test_correlation.cpython-314.pyc",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/test_cov_corr.py",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_autocorr.py",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/test_cov_corr.py",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/frame/methods/__pycache__/test_cov_corr.cpython-314.pyc",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_autocorr.cpython-314.pyc",
      "artifacts/experiments/spider_sql/.venv/lib/python3.14/site-packages/pandas/tests/series/methods/__pycache__/test_cov_corr.cpython-314.pyc",
      "artifacts/multi_model_error_correlation.py",
      "artifacts/exp_multi_model_correlation/report/multi_model_error_correlation.py",
      "checkpoints/exp_multi_model_correlation_QUEUED_20260521T020435.json",
      "checkpoints/exp_multi_model_correlation_RUNNING_20260521T020441.json",
      "checkpoints/exp_multi_model_correlation_RUNNING_20260521T020500.json",
      "checkpoints/exp_multi_model_correlation_DONE_20260521T020505.json",
      "logs/workers/worker_analysis_multi_model_error_correlation_20260521T015715.log",
      "logs/chats/worker_analysis_multi_model_error_correlation_20260521T015715.lock",
      "logs/chats/worker_analysis_multi_model_error_correlation_20260521T015715.jsonl",
      "logs/workers/worker_analysis_multi_model_error_correlation_20260521T015715_result.json",
      "artifacts/_project/report/d220_correction_notes.md",
      "artifacts/_project/report/d220_correction_notes_4e5dea.md",
      "artifacts/d220_correction_notes.md"
    ],
    "durationMs": 114,
    "numFiles": 83,
    "truncated": false
  }
}
```

</details>

---

### Assistant

_source line 19_

<details><summary>Logged reasoning block</summary>

```text
Let me now read the Abstract source file and the key data files in parallel. The active constraint says to use `docs/paper/sections/` for the compilation version, not `artifacts/_project/paper/`. Let me read the Abstract from `docs/paper/sections/abstract.tex` and also the unified rho data and relevant reports.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "0ddff842-0975-41f8-9c99-d8b697e5cab4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FBYrkB2Eg9ZD6D4PG3nAQh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7932,
      "cache_read_input_tokens": 24606,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7932
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

_source line 20_

Let me read the Abstract and the key ρ data files in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "4c09ea5e-0f75-4648-91aa-9b035a8b24e2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FBYrkB2Eg9ZD6D4PG3nAQh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7932,
      "cache_read_input_tokens": 24606,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7932
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

_source line 21_

<details open><summary>🔧 Tool call — Read · `toolu_01Tzr2f2tXsrCrwrV9w8MGKd`</summary>

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
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "cc243c0b-048e-47f3-b994-ecca3fbfdf36",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FBYrkB2Eg9ZD6D4PG3nAQh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7932,
      "cache_read_input_tokens": 24606,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7932
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

_source line 22 · 2026-05-21T12:00:34.056Z_

<details><summary>↩ Tool result · `toolu_01Tzr2f2tXsrCrwrV9w8MGKd`</summary>

```text
1	\begin{abstract}
2	Test-time compute scaling through repeated sampling yields large gains on discrete-answer reasoning and code generation, yet for structured information extraction (IE), where outputs are entity sets with partial overlap, a persistent gap separates quality estimation from sample selection.
3	We ask whether entity-level agreement signals can bridge this gap.
4	Across seven methods spanning self-judgment, self-refinement, latent consistency, heterogeneous verification, adaptive budgeting, distillation, and supervised classification, we find that no entity-level agreement signal reliably improves selection for named entity recognition (NER), relation extraction (RE), or Text-to-SQL.
5	Quality estimation signals correlate with oracle F1 ($\rho$ up to 0.45, AUROC up to 0.82) yet no signal selects better than greedy decoding.
6	The failure is systematic: a four-stage diagnostic cascade (quality estimation $\to$ degeneracy $\to$ agreement fidelity $\to$ log-probability compression) localizes where and why selection breaks down, with cross-task validation on SQL parsing (87.2\% output degeneracy).
7	A hidden-state linear probe achieves entity-level discrimination (area under the ROC curve [AUROC] $0.63$\textendash$0.88$, dataset-dependent) from a single forward pass, consistently exceeding prompt-based self-evaluation (AUROC 0.51) but matching multi-sample agreement ($0.87$) only on the simplest task.
8	These negative results delineate where self-consistency (SC) does succeed for IE: through paths that bypass entity-level agreement.
9	Log-probability selection improves F1 by $+1.39$\,pp on Few-NERD (Holm-adjusted $p{=}0.019$, selection family $k{=}19$), entity-level construction via weighted voting gains $+1.02$\textendash$1.40$\,pp, and cross-model ensembles add $+0.42$\,pp on Few-NERD.
10	Each exploits sequence-level or cross-model signals rather than entity-level self-verification.
11	A degeneracy decomposition confirms SC gain vanishes once output degeneracy exceeds 70\%.
12	\end{abstract}
13	%% REFRAME: scope precision + empirical exhaustion methodology
14	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "ea984bcf-e559-4d26-b7ca-90585bd989f8",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/abstract.tex",
      "content": "\\begin{abstract}\nTest-time compute scaling through repeated sampling yields large gains on discrete-answer reasoning and code generation, yet for structured information extraction (IE), where outputs are entity sets with partial overlap, a persistent gap separates quality estimation from sample selection.\nWe ask whether entity-level agreement signals can bridge this gap.\nAcross seven methods spanning self-judgment, self-refinement, latent consistency, heterogeneous verification, adaptive budgeting, distillation, and supervised classification, we find that no entity-level agreement signal reliably improves selection for named entity recognition (NER), relation extraction (RE), or Text-to-SQL.\nQuality estimation signals correlate with oracle F1 ($\\rho$ up to 0.45, AUROC up to 0.82) yet no signal selects better than greedy decoding.\nThe failure is systematic: a four-stage diagnostic cascade (quality estimation $\\to$ degeneracy $\\to$ agreement fidelity $\\to$ log-probability compression) localizes where and why selection breaks down, with cross-task validation on SQL parsing (87.2\\% output degeneracy).\nA hidden-state linear probe achieves entity-level discrimination (area under the ROC curve [AUROC] $0.63$\\textendash$0.88$, dataset-dependent) from a single forward pass, consistently exceeding prompt-based self-evaluation (AUROC 0.51) but matching multi-sample agreement ($0.87$) only on the simplest task.\nThese negative results delineate where self-consistency (SC) does succeed for IE: through paths that bypass entity-level agreement.\nLog-probability selection improves F1 by $+1.39$\\,pp on Few-NERD (Holm-adjusted $p{=}0.019$, selection family $k{=}19$), entity-level construction via weighted voting gains $+1.02$\\textendash$1.40$\\,pp, and cross-model ensembles add $+0.42$\\,pp on Few-NERD.\nEach exploits sequence-level or cross-model signals rather than entity-level self-verification.\nA degeneracy decomposition confirms SC gain vanishes once output degeneracy exceeds 70\\%.\n\\end{abstract}\n%% REFRAME: scope precision + empirical exhaustion methodology\n",
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

_source line 23_

<details open><summary>🔧 Tool call — Read · `toolu_01K66LGq8hX2ESgeUFBTV4fL`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/analysis_unified_rho.json"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "cda56e8e-dac4-4bb1-9323-db304db68fca",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FBYrkB2Eg9ZD6D4PG3nAQh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7932,
      "cache_read_input_tokens": 24606,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7932
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

_source line 24 · 2026-05-21T12:00:34.485Z_

<details><summary>↩ Tool result · `toolu_01K66LGq8hX2ESgeUFBTV4fL`</summary>

```text
1	{
2	  "audit_date": "2026-05-15",
3	  "pipeline": "unified (gold-filtered, consistency.py FK/SJ, evaluation.py per_instance_f1)",
4	  "filter": "exclude instances where len(gold.entities) == 0",
5	  "experiments": {
6	    "exp_017_llama_conll_n16_r1024": {
7	      "description": "LLaMA CoNLL seed42 n16 r1024",
8	      "n_total": 3453,
9	      "n_gold_empty": 697,
10	      "n_valid": 2756,
11	      "n_conditional": 2641,
12	      "old_registry_rho_fk": 0.8095,
13	      "old_registry_rho_sj": 0.1815,
14	      "unified_full": {
15	        "rho_fk": 0.4752,
16	        "rho_sj": 0.4836,
17	        "rho_vc": 0.4746,
18	        "rho_em": 0.4818,
19	        "rho_lp": 0.3136,
20	        "auroc_fk": 0.7467,
21	        "auroc_sj": 0.7496,
22	        "auroc_vc": 0.7529,
23	        "auroc_em": 0.7508,
24	        "auroc_lp": 0.7661,
25	        "median_f1": 1.0
26	      },
27	      "unified_conditional": {
28	        "rho_fk": 0.4767,
29	        "rho_sj": 0.4856
30	      }
31	    },
32	    "exp_017_llama_conll_n16_s456_r1024": {
33	      "description": "LLaMA CoNLL seed456 n16 r1024",
34	      "n_total": 3453,
35	      "n_gold_empty": 697,
36	      "n_valid": 2756,
37	      "n_conditional": 2642,
38	      "old_registry_rho_fk": 0.8085,
39	      "old_registry_rho_sj": 0.1895,
40	      "unified_full": {
41	        "rho_fk": 0.469,
42	        "rho_sj": 0.4734,
43	        "rho_vc": 0.4722,
44	        "rho_em": 0.4752,
45	        "rho_lp": 0.3099,
46	        "auroc_fk": 0.7408,
47	        "auroc_sj": 0.7428,
48	        "auroc_vc": 0.7495,
49	        "auroc_em": 0.7444,
50	        "auroc_lp": 0.7628,
51	        "median_f1": 1.0
52	      },
53	      "unified_conditional": {
54	        "rho_fk": 0.4694,
55	        "rho_sj": 0.4728
56	      }
57	    },
58	    "exp_001_n16_seed456": {
59	      "description": "Qwen SciERC seed456 joint n16",
60	      "n_total": 551,
61	      "n_gold_empty": 22,
62	      "n_valid": 529,
63	      "n_conditional": 478,
64	      "old_registry_rho_fk": 0.3448,
65	      "old_registry_rho_sj": 0.4134,
66	      "unified_full_ner": {
67	        "rho_fk": 0.2723,
68	        "rho_sj": 0.4098,
69	        "rho_vc": 0.4449,
70	        "rho_em": 0.3363,
71	        "rho_lp": 0.2415,
72	        "auroc_fk": 0.6179,
73	        "auroc_sj": 0.6823,
74	        "auroc_vc": 0.6981,
75	        "auroc_em": 0.649,
76	        "auroc_lp": 0.5885,
77	        "median_f1": 0.6667
78	      },
79	      "unified_conditional_ner": {
80	        "rho_fk": 0.1887,
81	        "rho_sj": 0.3735
82	      },
83	      "unified_re": {
84	        "n_re_valid": 397,
85	        "rho_fk": 0.2929,
86	        "rho_sj": 0.2835
87	      }
88	    },
89	    "exp_011_ood_conll_to_scierc": {
90	      "description": "OOD ConLL-trained on SciERC test",
91	      "n_total": 551,
92	      "n_gold_empty": 22,
93	      "n_valid": 529,
94	      "n_conditional": 12,
95	      "registry_already_correct": true,
96	      "unified_full": {
97	        "rho_fk": -0.0695,
98	        "rho_sj": -0.1857,
99	        "rho_vc": 0.1972,
100	        "rho_em": -0.2015,
101	        "rho_lp": -0.1521
102	      }
103	    }
104	  }
105	}
106	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "8f1efe50-d075-4457-a134-f533b48805f0",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/analysis_unified_rho.json",
      "content": "{\n  \"audit_date\": \"2026-05-15\",\n  \"pipeline\": \"unified (gold-filtered, consistency.py FK/SJ, evaluation.py per_instance_f1)\",\n  \"filter\": \"exclude instances where len(gold.entities) == 0\",\n  \"experiments\": {\n    \"exp_017_llama_conll_n16_r1024\": {\n      \"description\": \"LLaMA CoNLL seed42 n16 r1024\",\n      \"n_total\": 3453,\n      \"n_gold_empty\": 697,\n      \"n_valid\": 2756,\n      \"n_conditional\": 2641,\n      \"old_registry_rho_fk\": 0.8095,\n      \"old_registry_rho_sj\": 0.1815,\n      \"unified_full\": {\n        \"rho_fk\": 0.4752,\n        \"rho_sj\": 0.4836,\n        \"rho_vc\": 0.4746,\n        \"rho_em\": 0.4818,\n        \"rho_lp\": 0.3136,\n        \"auroc_fk\": 0.7467,\n        \"auroc_sj\": 0.7496,\n        \"auroc_vc\": 0.7529,\n        \"auroc_em\": 0.7508,\n        \"auroc_lp\": 0.7661,\n        \"median_f1\": 1.0\n      },\n      \"unified_conditional\": {\n        \"rho_fk\": 0.4767,\n        \"rho_sj\": 0.4856\n      }\n    },\n    \"exp_017_llama_conll_n16_s456_r1024\": {\n      \"description\": \"LLaMA CoNLL seed456 n16 r1024\",\n      \"n_total\": 3453,\n      \"n_gold_empty\": 697,\n      \"n_valid\": 2756,\n      \"n_conditional\": 2642,\n      \"old_registry_rho_fk\": 0.8085,\n      \"old_registry_rho_sj\": 0.1895,\n      \"unified_full\": {\n        \"rho_fk\": 0.469,\n        \"rho_sj\": 0.4734,\n        \"rho_vc\": 0.4722,\n        \"rho_em\": 0.4752,\n        \"rho_lp\": 0.3099,\n        \"auroc_fk\": 0.7408,\n        \"auroc_sj\": 0.7428,\n        \"auroc_vc\": 0.7495,\n        \"auroc_em\": 0.7444,\n        \"auroc_lp\": 0.7628,\n        \"median_f1\": 1.0\n      },\n      \"unified_conditional\": {\n        \"rho_fk\": 0.4694,\n        \"rho_sj\": 0.4728\n      }\n    },\n    \"exp_001_n16_seed456\": {\n      \"description\": \"Qwen SciERC seed456 joint n16\",\n      \"n_total\": 551,\n      \"n_gold_empty\": 22,\n      \"n_valid\": 529,\n      \"n_conditional\": 478,\n      \"old_registry_rho_fk\": 0.3448,\n      \"old_registry_rho_sj\": 0.4134,\n      \"unified_full_ner\": {\n        \"rho_fk\": 0.2723,\n        \"rho_sj\": 0.4098,\n        \"rho_vc\": 0.4449,\n        \"rho_em\": 0.3363,\n        \"rho_lp\": 0.2415,\n        \"auroc_fk\": 0.6179,\n        \"auroc_sj\": 0.6823,\n        \"auroc_vc\": 0.6981,\n        \"auroc_em\": 0.649,\n        \"auroc_lp\": 0.5885,\n        \"median_f1\": 0.6667\n      },\n      \"unified_conditional_ner\": {\n        \"rho_fk\": 0.1887,\n        \"rho_sj\": 0.3735\n      },\n      \"unified_re\": {\n        \"n_re_valid\": 397,\n        \"rho_fk\": 0.2929,\n        \"rho_sj\": 0.2835\n      }\n    },\n    \"exp_011_ood_conll_to_scierc\": {\n      \"description\": \"OOD ConLL-trained on SciERC test\",\n      \"n_total\": 551,\n      \"n_gold_empty\": 22,\n      \"n_valid\": 529,\n      \"n_conditional\": 12,\n      \"registry_already_correct\": true,\n      \"unified_full\": {\n        \"rho_fk\": -0.0695,\n        \"rho_sj\": -0.1857,\n        \"rho_vc\": 0.1972,\n        \"rho_em\": -0.2015,\n        \"rho_lp\": -0.1521\n      }\n    }\n  }\n}\n",
      "numLines": 106,
      "startLine": 1,
      "totalLines": 106
    }
  }
}
```

</details>

---

### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Read · `toolu_01UcWwJnBMHg6jbtVVfRDF4z`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/report/rho_consistency_audit.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "2abac3a8-8d06-4244-b050-1b72a3eacf43",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FBYrkB2Eg9ZD6D4PG3nAQh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7932,
      "cache_read_input_tokens": 24606,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7932
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

_source line 26 · 2026-05-21T12:00:35.470Z_

<details><summary>↩ Tool result · `toolu_01UcWwJnBMHg6jbtVVfRDF4z`</summary>

```text
1	# Rho Consistency Audit Report
2	
3	**Date**: 2026-05-15
4	**Trigger**: Reviewer flagged large discrepancies between registry rho values and bootstrap CI rho values
5	
6	## Root Cause
7	
8	The discrepancy comes from two different evaluation pipelines using different instance filtering:
9	
10	### Old Pipeline (`compute_metrics.py`)
11	- **No filtering**: uses ALL instances including gold-empty ones
12	- **FK bug**: `compute_fk()` returns 0.0 when all samples predict no entities (should be 1.0 = perfect agreement on empty set)
13	- **F1 convention**: returns 0.0 when tp=0, including when both pred and gold are empty
14	
15	### New Pipeline (`eval_n16_5signal.py`, `fk_bootstrap_ci.py`, `analyze_exp017_*.py`)
16	- **Filters out gold-empty instances**: `len(gold.get("entities", [])) > 0`
17	- **Uses `consistency.py`**: `fleiss_kappa_surface()` returns 1.0 for all-empty (correct)
18	- **Reports n_valid** separate from n_total
19	
20	### Mechanism of Inflation / Deflation
21	
22	For CoNLL2003 (3453 test sentences), **697 instances (20.2%) have zero gold entities**.
23	
24	For these gold-empty instances in the old pipeline:
25	- All samples typically predict few/no entities → **FK ≈ 0.04** (buggy), **F1 = 0.0**
26	- All samples agree on empty output → **SJ ≈ 0.98**, **F1 = 0.0**
27	
28	Adding 697 points at (FK≈0, F1=0) creates a strong artificial cluster that inflates Spearman rho for FK.
29	Adding 697 points at (SJ≈1, F1=0) creates an anti-correlated cluster that deflates Spearman rho for SJ.
30	
31	This is why FK rho jumped from 0.48 to 0.81, while SJ rho dropped from 0.48 to 0.18 — a complete **rank reversal**.
32	
33	## Affected Experiments
34	
35	| exp_id | Signal | Old (registry) | New (correct) | Delta | Instance Change |
36	|--------|--------|----------------|---------------|-------|-----------------|
37	| exp_017_llama_conll_n16_r1024 | FK | **0.8095** | **0.4752** | -0.3343 | 3453→2756 |
38	| exp_017_llama_conll_n16_r1024 | SJ | **0.1815** | **0.4836** | +0.3021 | 3453→2756 |
39	| exp_017_llama_conll_n16_s456_r1024 | FK | **0.8085** | **0.4690** | -0.3395 | 3453→2756 |
40	| exp_017_llama_conll_n16_s456_r1024 | SJ | **0.1895** | **0.4734** | +0.2839 | 3453→2756 |
41	| exp_001_n16_seed456 | FK | **0.3448** | **0.2723** | -0.0725 | 551→529 |
42	| exp_001_n16_seed456 | SJ | **0.4134** | **0.4098** | -0.0036 | 551→529 |
43	| exp_011_ood_conll_to_scierc | FK | -0.069 | -0.0695 | ~0 | Already correct |
44	| exp_011_ood_conll_to_scierc | SJ | -0.186 | -0.1857 | ~0 | Already correct |
45	
46	## Correct (Unified) Pipeline Specification
47	
48	**Filter**: Exclude instances where `len(gold.get("entities", [])) == 0`
49	**FK implementation**: `consistency.py::fleiss_kappa_surface()` (returns 1.0 for all-empty samples)
50	**SJ implementation**: `consistency.py::structural_consistency_soft_jaccard()`
51	**F1**: `evaluation.py::per_instance_f1()` (per-instance, not micro-averaged)
52	**Spearman rho**: `scipy.stats.spearmanr` on (signal, F1) pairs, excluding NaN
53	
54	## Unified Rho Values (Full Split, Gold-Filtered)
55	
56	### LLaMA CoNLL seed42 (n=2756)
57	| Signal | rho | AUROC |
58	|--------|-----|-------|
59	| FK | 0.4752 | 0.7467 |
60	| SJ | 0.4836 | 0.7496 |
61	| VC | 0.4746 | 0.7529 |
62	| EM | 0.4818 | 0.7508 |
63	| LP | 0.3136 | 0.7661 |
64	
65	### LLaMA CoNLL seed456 (n=2756)
66	| Signal | rho | AUROC |
67	|--------|-----|-------|
68	| FK | 0.4690 | 0.7408 |
69	| SJ | 0.4734 | 0.7428 |
70	| VC | 0.4722 | 0.7495 |
71	| EM | 0.4752 | 0.7444 |
72	| LP | 0.3099 | 0.7628 |
73	
74	### Qwen SciERC seed456 NER (n=529)
75	| Signal | rho | AUROC |
76	|--------|-----|-------|
77	| FK | 0.2723 | 0.6179 |
78	| SJ | 0.4098 | 0.6823 |
79	| VC | 0.4449 | 0.6981 |
80	| EM | 0.3363 | 0.6490 |
81	| LP | 0.2415 | 0.5885 |
82	
83	### Qwen SciERC seed456 RE (n=397)
84	| Signal | rho |
85	|--------|-----|
86	| FK | 0.2929 |
87	| SJ | 0.2835 |
88	
89	### OOD ConLL→SciERC (n=529, already correct in registry)
90	| Signal | rho |
91	|--------|-----|
92	| FK | -0.0695 |
93	| SJ | -0.1857 |
94	
95	## Impact on Paper
96	
97	1. **LLaMA CoNLL results need correction**: The claim that FK dominates (rho=0.81) is wrong. With correct filtering, all structural signals have similar rho (~0.47-0.48), and SJ slightly edges FK.
98	2. **Rank reversal resolved**: SJ and FK are now comparable rather than opposite.
99	3. **SciERC seed456 minor change**: FK drops from 0.34 to 0.27; SJ essentially unchanged.
100	4. **Key narrative change**: The story shifts from "FK is best for NER" to "all structural signals are comparable; logprob is weaker" — which is actually a cleaner finding.
101	
102	## Registry Updates Required
103	
104	- `exp_017_llama_conll_n16_r1024`: replace flat rho metrics with new pipeline values
105	- `exp_017_llama_conll_n16_s456_r1024`: replace flat rho metrics with new pipeline values
106	- `exp_001_n16_seed456`: replace flat rho metrics with new pipeline values
107	- `exp_011_ood_conll_to_scierc`: no change needed (already correct)
108	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "94cbbe04-140c-4ee7-9b99-456244d0c000",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/report/rho_consistency_audit.md",
      "content": "# Rho Consistency Audit Report\n\n**Date**: 2026-05-15\n**Trigger**: Reviewer flagged large discrepancies between registry rho values and bootstrap CI rho values\n\n## Root Cause\n\nThe discrepancy comes from two different evaluation pipelines using different instance filtering:\n\n### Old Pipeline (`compute_metrics.py`)\n- **No filtering**: uses ALL instances including gold-empty ones\n- **FK bug**: `compute_fk()` returns 0.0 when all samples predict no entities (should be 1.0 = perfect agreement on empty set)\n- **F1 convention**: returns 0.0 when tp=0, including when both pred and gold are empty\n\n### New Pipeline (`eval_n16_5signal.py`, `fk_bootstrap_ci.py`, `analyze_exp017_*.py`)\n- **Filters out gold-empty instances**: `len(gold.get(\"entities\", [])) > 0`\n- **Uses `consistency.py`**: `fleiss_kappa_surface()` returns 1.0 for all-empty (correct)\n- **Reports n_valid** separate from n_total\n\n### Mechanism of Inflation / Deflation\n\nFor CoNLL2003 (3453 test sentences), **697 instances (20.2%) have zero gold entities**.\n\nFor these gold-empty instances in the old pipeline:\n- All samples typically predict few/no entities → **FK ≈ 0.04** (buggy), **F1 = 0.0**\n- All samples agree on empty output → **SJ ≈ 0.98**, **F1 = 0.0**\n\nAdding 697 points at (FK≈0, F1=0) creates a strong artificial cluster that inflates Spearman rho for FK.\nAdding 697 points at (SJ≈1, F1=0) creates an anti-correlated cluster that deflates Spearman rho for SJ.\n\nThis is why FK rho jumped from 0.48 to 0.81, while SJ rho dropped from 0.48 to 0.18 — a complete **rank reversal**.\n\n## Affected Experiments\n\n| exp_id | Signal | Old (registry) | New (correct) | Delta | Instance Change |\n|--------|--------|----------------|---------------|-------|-----------------|\n| exp_017_llama_conll_n16_r1024 | FK | **0.8095** | **0.4752** | -0.3343 | 3453→2756 |\n| exp_017_llama_conll_n16_r1024 | SJ | **0.1815** | **0.4836** | +0.3021 | 3453→2756 |\n| exp_017_llama_conll_n16_s456_r1024 | FK | **0.8085** | **0.4690** | -0.3395 | 3453→2756 |\n| exp_017_llama_conll_n16_s456_r1024 | SJ | **0.1895** | **0.4734** | +0.2839 | 3453→2756 |\n| exp_001_n16_seed456 | FK | **0.3448** | **0.2723** | -0.0725 | 551→529 |\n| exp_001_n16_seed456 | SJ | **0.4134** | **0.4098** | -0.0036 | 551→529 |\n| exp_011_ood_conll_to_scierc | FK | -0.069 | -0.0695 | ~0 | Already correct |\n| exp_011_ood_conll_to_scierc | SJ | -0.186 | -0.1857 | ~0 | Already correct |\n\n## Correct (Unified) Pipeline Specification\n\n**Filter**: Exclude instances where `len(gold.get(\"entities\", [])) == 0`\n**FK implementation**: `consistency.py::fleiss_kappa_surface()` (returns 1.0 for all-empty samples)\n**SJ implementation**: `consistency.py::structural_consistency_soft_jaccard()`\n**F1**: `evaluation.py::per_instance_f1()` (per-instance, not micro-averaged)\n**Spearman rho**: `scipy.stats.spearmanr` on (signal, F1) pairs, excluding NaN\n\n## Unified Rho Values (Full Split, Gold-Filtered)\n\n### LLaMA CoNLL seed42 (n=2756)\n| Signal | rho | AUROC |\n|--------|-----|-------|\n| FK | 0.4752 | 0.7467 |\n| SJ | 0.4836 | 0.7496 |\n| VC | 0.4746 | 0.7529 |\n| EM | 0.4818 | 0.7508 |\n| LP | 0.3136 | 0.7661 |\n\n### LLaMA CoNLL seed456 (n=2756)\n| Signal | rho | AUROC |\n|--------|-----|-------|\n| FK | 0.4690 | 0.7408 |\n| SJ | 0.4734 | 0.7428 |\n| VC | 0.4722 | 0.7495 |\n| EM | 0.4752 | 0.7444 |\n| LP | 0.3099 | 0.7628 |\n\n### Qwen SciERC seed456 NER (n=529)\n| Signal | rho | AUROC |\n|--------|-----|-------|\n| FK | 0.2723 | 0.6179 |\n| SJ | 0.4098 | 0.6823 |\n| VC | 0.4449 | 0.6981 |\n| EM | 0.3363 | 0.6490 |\n| LP | 0.2415 | 0.5885 |\n\n### Qwen SciERC seed456 RE (n=397)\n| Signal | rho |\n|--------|-----|\n| FK | 0.2929 |\n| SJ | 0.2835 |\n\n### OOD ConLL→SciERC (n=529, already correct in registry)\n| Signal | rho |\n|--------|-----|\n| FK | -0.0695 |\n| SJ | -0.1857 |\n\n## Impact on Paper\n\n1. **LLaMA CoNLL results need correction**: The claim that FK dominates (rho=0.81) is wrong. With correct filtering, all structural signals have similar rho (~0.47-0.48), and SJ slightly edges FK.\n2. **Rank reversal resolved**: SJ and FK are now comparable rather than opposite.\n3. **SciERC seed456 minor change**: FK drops from 0.34 to 0.27; SJ essentially unchanged.\n4. **Key narrative change**: The story shifts from \"FK is best for NER\" to \"all structural signals are comparable; logprob is weaker\" — which is actually a cleaner finding.\n\n## Registry Updates Required\n\n- `exp_017_llama_conll_n16_r1024`: replace flat rho metrics with new pipeline values\n- `exp_017_llama_conll_n16_s456_r1024`: replace flat rho metrics with new pipeline values\n- `exp_001_n16_seed456`: replace flat rho metrics with new pipeline values\n- `exp_011_ood_conll_to_scierc`: no change needed (already correct)\n",
      "numLines": 108,
      "startLine": 1,
      "totalLines": 108
    }
  }
}
```

</details>

---

### Tool call

_source line 27_

<details open><summary>🔧 Tool call — Read · `toolu_01HMMRWkU95qnQnbC99yhnFL`</summary>

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
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "8fb989d5-0c6b-42ff-9578-1a08ad96aacd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FBYrkB2Eg9ZD6D4PG3nAQh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7932,
      "cache_read_input_tokens": 24606,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7932
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

_source line 28 · 2026-05-21T12:00:36.403Z_

<details><summary>↩ Tool result · `toolu_01HMMRWkU95qnQnbC99yhnFL`</summary>

```text
1	## α_crit Entity Selection Bound (v3 — MF4v2 micro_f1)
2	
3	> ⚠️ v1/v2 基于 macro_f1 数据，已作废。本版使用 MF4v2 pipeline 的 micro_f1（aggregate TP/FP/FN）。
4	
5	### Main Table (T=1.0, MF4v2 micro-F1, multi-seed mean±σ)
6	
7	| Dataset | Seeds | greedy_f1 | mv_f1 | oracle_f1 | Δ_SC (pp) | π_MV | α_crit | δ (degen) | α_crit_eff | Bound Predicts | Empirical |
8	|---------|-------|-----------|-------|-----------|-----------|------|--------|-----------|------------|----------------|-----------|
9	| FewNERD | 3 (42/123/456) | 0.7911 | 0.7828 | 0.8851 | **−0.83±0.38** | 0.7828 | 0.6430 | 8.8% | 0.7049 | — | **No** |
10	| CoNLL   | 3 (42/123/456) | 0.9107 | 0.9123 | 0.9513 | **+0.16±0.12** | 0.9123 | 0.8388 | 62.1% | 2.213 | — | **Marginal** |
11	| SciERC  | 3 (42/123/456) | 0.6663 | 0.6678 | 0.7808 | **+0.15±0.18** | 0.6678 | 0.5013 | 12.2% | 0.5707 | — | **Marginal** |
12	
13	- **Δ_SC** = mv_f1 − greedy_f1 (positive = MV wins). All |Δ| < 1pp.
14	- **α_crit** = π_MV / (2 − π_MV)
15	- **α_crit_eff** = α_crit / (1 − δ). CoNLL α_crit_eff > 1.0 means MV gain is structurally impossible given degeneracy.
16	- **δ**: fraction of instances where all N=8 samples produce identical entity sets.
17	
18	### Per-Seed Detail
19	
20	#### FewNERD (n=32,565 gold-non-empty instances per seed)
21	
22	| Seed | greedy_f1 | mv_f1 | oracle_f1 | degen | α_crit | Δ_SC (pp) |
23	|------|-----------|-------|-----------|-------|--------|-----------|
24	| 42   | 0.7909 | 0.7781 | 0.8802 | 9.1% | 0.6368 | −1.28 |
25	| 123  | 0.7909 | 0.7844 | 0.8897 | 9.2% | 0.6453 | −0.64 |
26	| 456  | 0.7916 | 0.7857 | 0.8855 | 8.1% | 0.6471 | −0.58 |
27	
28	#### CoNLL (n=2,756 gold-non-empty instances per seed)
29	
30	| Seed | greedy_f1 | mv_f1 | oracle_f1 | degen | α_crit | Δ_SC (pp) |
31	|------|-----------|-------|-----------|-------|--------|-----------|
32	| 42   | 0.9075 | 0.9090 | 0.9495 | 65.7% | 0.8332 | +0.15 |
33	| 123  | 0.9129 | 0.9157 | 0.9543 | 60.4% | 0.8445 | +0.28 |
34	| 456  | 0.9118 | 0.9122 | 0.9500 | 60.2% | 0.8386 | +0.04 |
35	
36	#### SciERC (n=529 gold-non-empty instances per seed)
37	
38	| Seed | greedy_f1 | mv_f1 | oracle_f1 | degen | α_crit | Δ_SC (pp) |
39	|------|-----------|-------|-----------|-------|--------|-----------|
40	| 42   | 0.6663 | 0.6657 | 0.7839 | 13.4% | 0.4989 | −0.06 |
41	| 123  | 0.6663 | 0.6689 | 0.7789 | 11.0% | 0.5025 | +0.26 |
42	| 456  | 0.6663 | 0.6687 | 0.7795 | 12.1% | 0.5023 | +0.24 |
43	
44	### Key Finding
45	
46	**MV ≈ greedy (|Δ| < 1pp)**. SC captures negligible fraction of oracle headroom (4–11pp available).
47	
48	- FewNERD: MV loses 0.83pp on average. Despite ~9% degeneracy and ~9pp oracle headroom, MV slightly *hurts*.
49	- CoNLL: MV gains 0.16pp on average. High degeneracy (60%) means most instances are trivially correct; MV barely moves the needle.
50	- SciERC: MV gains 0.15pp on average. Despite ~11pp oracle headroom, MV improvement is negligible.
51	
52	Agreement signals predict quality (soft_jaccard ρ=0.31–0.46) but MV fails to translate correlation into selection improvement. The bottleneck is structural: entity-level MV aggregates across misaligned span boundaries, introducing errors absent from any individual sample.
53	
54	### Old vs New Comparison (version history)
55	
56	| Version | Δ Definition | Metric | FewNERD Δ | CoNLL Δ | SciERC Δ | Status |
57	|---------|-------------|--------|-----------|---------|----------|--------|
58	| v1 | θ2n − greedy | macro_f1 | +0.89 | −1.09 | +0.76 | ❌ Wrong Δ |
59	| v2 | MV − greedy | macro_f1 | −9.21 | −1.37 | −3.03 | ❌ Macro bug |
60	| **v3** | **MV − greedy** | **micro_f1** | **−0.83** | **+0.16** | **+0.15** | **✓ Correct** |
61	
62	v2 → v3 correction: macro-F1 dramatically over-weights instances with few entities where MV tends to produce empty outputs. micro-F1 (aggregate TP/FP/FN) shows MV is approximately neutral, not catastrophically bad.
63	
64	### Data Sources
65	
66	- FewNERD: MF4v2 pipeline, Qwen3-8B-FT, N=8, T=1.0
67	  - seed 42: `fewnerd_mf4v2_seed42/samples.jsonl` (bjb2-11496)
68	  - seed 123: `fewnerd_mf4v2_seed123/samples.jsonl` (bjb2-11496)
69	  - seed 456: `fewnerd_mf4v2_seed456/samples.jsonl` (autodl-5090)
70	- CoNLL: MF4v2 pipeline, Qwen3-8B-FT, N=8, T=1.0
71	  - seed 42: `conll_mf4v2_seed42/samples.jsonl` (autodl-5090-c)
72	  - seed 123: `conll_mf4v2_seed123/samples.jsonl` (bjb2-11496)
73	  - seed 456: `conll_mf4v2_seed456/samples.jsonl` (bjb2-11496)
74	- SciERC: MF4v2 pipeline, Qwen3-8B-FT, N=8, T=1.0
75	  - seed 42: `scierc_mf4v2_seed42/samples.jsonl` (bjb2-11496)
76	  - seed 123: `scierc_mf4v2_seed123/samples.jsonl` (autodl-5090)
77	  - seed 456: `scierc_mf4v2_seed456/samples.jsonl` (autodl-5090)
78	- Computed 2026-05-21 via entity-level exact match (text, type, start, end) with micro-F1 (aggregate TP/FP/FN)
79	- MV threshold: entity included if it appears in ≥ N/2 = 4 of 8 samples
80	- Oracle: per-instance best-sample by instance F1
81	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "b870f278-1621-48b6-8fb6-a02da752dd4c",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/alpha_crit_table.md",
      "content": "## α_crit Entity Selection Bound (v3 — MF4v2 micro_f1)\n\n> ⚠️ v1/v2 基于 macro_f1 数据，已作废。本版使用 MF4v2 pipeline 的 micro_f1（aggregate TP/FP/FN）。\n\n### Main Table (T=1.0, MF4v2 micro-F1, multi-seed mean±σ)\n\n| Dataset | Seeds | greedy_f1 | mv_f1 | oracle_f1 | Δ_SC (pp) | π_MV | α_crit | δ (degen) | α_crit_eff | Bound Predicts | Empirical |\n|---------|-------|-----------|-------|-----------|-----------|------|--------|-----------|------------|----------------|-----------|\n| FewNERD | 3 (42/123/456) | 0.7911 | 0.7828 | 0.8851 | **−0.83±0.38** | 0.7828 | 0.6430 | 8.8% | 0.7049 | — | **No** |\n| CoNLL   | 3 (42/123/456) | 0.9107 | 0.9123 | 0.9513 | **+0.16±0.12** | 0.9123 | 0.8388 | 62.1% | 2.213 | — | **Marginal** |\n| SciERC  | 3 (42/123/456) | 0.6663 | 0.6678 | 0.7808 | **+0.15±0.18** | 0.6678 | 0.5013 | 12.2% | 0.5707 | — | **Marginal** |\n\n- **Δ_SC** = mv_f1 − greedy_f1 (positive = MV wins). All |Δ| < 1pp.\n- **α_crit** = π_MV / (2 − π_MV)\n- **α_crit_eff** = α_crit / (1 − δ). CoNLL α_crit_eff > 1.0 means MV gain is structurally impossible given degeneracy.\n- **δ**: fraction of instances where all N=8 samples produce identical entity sets.\n\n### Per-Seed Detail\n\n#### FewNERD (n=32,565 gold-non-empty instances per seed)\n\n| Seed | greedy_f1 | mv_f1 | oracle_f1 | degen | α_crit | Δ_SC (pp) |\n|------|-----------|-------|-----------|-------|--------|-----------|\n| 42   | 0.7909 | 0.7781 | 0.8802 | 9.1% | 0.6368 | −1.28 |\n| 123  | 0.7909 | 0.7844 | 0.8897 | 9.2% | 0.6453 | −0.64 |\n| 456  | 0.7916 | 0.7857 | 0.8855 | 8.1% | 0.6471 | −0.58 |\n\n#### CoNLL (n=2,756 gold-non-empty instances per seed)\n\n| Seed | greedy_f1 | mv_f1 | oracle_f1 | degen | α_crit | Δ_SC (pp) |\n|------|-----------|-------|-----------|-------|--------|-----------|\n| 42   | 0.9075 | 0.9090 | 0.9495 | 65.7% | 0.8332 | +0.15 |\n| 123  | 0.9129 | 0.9157 | 0.9543 | 60.4% | 0.8445 | +0.28 |\n| 456  | 0.9118 | 0.9122 | 0.9500 | 60.2% | 0.8386 | +0.04 |\n\n#### SciERC (n=529 gold-non-empty instances per seed)\n\n| Seed | greedy_f1 | mv_f1 | oracle_f1 | degen | α_crit | Δ_SC (pp) |\n|------|-----------|-------|-----------|-------|--------|-----------|\n| 42   | 0.6663 | 0.6657 | 0.7839 | 13.4% | 0.4989 | −0.06 |\n| 123  | 0.6663 | 0.6689 | 0.7789 | 11.0% | 0.5025 | +0.26 |\n| 456  | 0.6663 | 0.6687 | 0.7795 | 12.1% | 0.5023 | +0.24 |\n\n### Key Finding\n\n**MV ≈ greedy (|Δ| < 1pp)**. SC captures negligible fraction of oracle headroom (4–11pp available).\n\n- FewNERD: MV loses 0.83pp on average. Despite ~9% degeneracy and ~9pp oracle headroom, MV slightly *hurts*.\n- CoNLL: MV gains 0.16pp on average. High degeneracy (60%) means most instances are trivially correct; MV barely moves the needle.\n- SciERC: MV gains 0.15pp on average. Despite ~11pp oracle headroom, MV improvement is negligible.\n\nAgreement signals predict quality (soft_jaccard ρ=0.31–0.46) but MV fails to translate correlation into selection improvement. The bottleneck is structural: entity-level MV aggregates across misaligned span boundaries, introducing errors absent from any individual sample.\n\n### Old vs New Comparison (version history)\n\n| Version | Δ Definition | Metric | FewNERD Δ | CoNLL Δ | SciERC Δ | Status |\n|---------|-------------|--------|-----------|---------|----------|--------|\n| v1 | θ2n − greedy | macro_f1 | +0.89 | −1.09 | +0.76 | ❌ Wrong Δ |\n| v2 | MV − greedy | macro_f1 | −9.21 | −1.37 | −3.03 | ❌ Macro bug |\n| **v3** | **MV − greedy** | **micro_f1** | **−0.83** | **+0.16** | **+0.15** | **✓ Correct** |\n\nv2 → v3 correction: macro-F1 dramatically over-weights instances with few entities where MV tends to produce empty outputs. micro-F1 (aggregate TP/FP/FN) shows MV is approximately neutral, not catastrophically bad.\n\n### Data Sources\n\n- FewNERD: MF4v2 pipeline, Qwen3-8B-FT, N=8, T=1.0\n  - seed 42: `fewnerd_mf4v2_seed42/samples.jsonl` (bjb2-11496)\n  - seed 123: `fewnerd_mf4v2_seed123/samples.jsonl` (bjb2-11496)\n  - seed 456: `fewnerd_mf4v2_seed456/samples.jsonl` (autodl-5090)\n- CoNLL: MF4v2 pipeline, Qwen3-8B-FT, N=8, T=1.0\n  - seed 42: `conll_mf4v2_seed42/samples.jsonl` (autodl-5090-c)\n  - seed 123: `conll_mf4v2_seed123/samples.jsonl` (bjb2-11496)\n  - seed 456: `conll_mf4v2_seed456/samples.jsonl` (bjb2-11496)\n- SciERC: MF4v2 pipeline, Qwen3-8B-FT, N=8, T=1.0\n  - seed 42: `scierc_mf4v2_seed42/samples.jsonl` (bjb2-11496)\n  - seed 123: `scierc_mf4v2_seed123/samples.jsonl` (autodl-5090)\n  - seed 456: `scierc_mf4v2_seed456/samples.jsonl` (autodl-5090)\n- Computed 2026-05-21 via entity-level exact match (text, type, start, end) with micro-F1 (aggregate TP/FP/FN)\n- MV threshold: entity included if it appears in ≥ N/2 = 4 of 8 samples\n- Oracle: per-instance best-sample by instance F1\n",
      "numLines": 81,
      "startLine": 1,
      "totalLines": 81
    }
  }
}
```

</details>

---

### Tool call

_source line 29_

<details open><summary>🔧 Tool call — Read · `toolu_01Tb8ZoFkbPYWG4pi18p2KoB`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/data/analysis_unified_rho_full.json"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "ea093241-90f7-4062-9754-0c0449dae028",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FBYrkB2Eg9ZD6D4PG3nAQh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7932,
      "cache_read_input_tokens": 24606,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7932
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

_source line 30 · 2026-05-21T12:00:36.813Z_

<details><summary>↩ Tool result · `toolu_01Tb8ZoFkbPYWG4pi18p2KoB`</summary>

```text
1	{
2	  "metadata": {
3	    "pipeline": "unified_gold_filtered",
4	    "date": "2026-05-15",
5	    "fk_empty_fix": true,
6	    "gold_filter": "exclude instances where len(gold.entities)==0",
7	    "conll_n_valid": 2756,
8	    "scierc_n_valid": 529,
9	    "data_fix_d093": {
10	      "date": "2026-05-15",
11	      "reason": "D093: LLaMA SciERC N=8 entries replaced with exp_018 clean rerun data. Old values from exp_007 pipeline had contaminated VC/EM rho and all AUROC values.",
12	      "source": "multi_seed_stability_table.md (compute_llama_3seed_summary.py)",
13	      "affected_entries": [
14	        "llama_scierc_n8_seed42",
15	        "llama_scierc_n8_seed123",
16	        "llama_scierc_n8_seed456 (added)"
17	      ],
18	      "three_seed_mean": {
19	        "SJ": 0.325,
20	        "FK": 0.256,
21	        "VC": 0.384,
22	        "EM": 0.279,
23	        "LP": 0.162
24	      }
25	    }
26	  },
27	  "results": {
28	    "llama_conll_n16_seed42": {
29	      "n_instances": 2756,
30	      "n_total": 3453,
31	      "n_gold_empty": 697,
32	      "VC": 0.4746,
33	      "SJ": 0.4836,
34	      "FK": 0.4752,
35	      "EM": 0.4818,
36	      "LP": 0.3136,
37	      "auroc_VC": 0.7529,
38	      "auroc_SJ": 0.7496,
39	      "auroc_FK": 0.7467,
40	      "auroc_EM": 0.7508,
41	      "auroc_LP": 0.7661
42	    },
43	    "llama_conll_n16_seed123": {
44	      "n_instances": 2756,
45	      "n_total": 3453,
46	      "n_gold_empty": 697,
47	      "VC": 0.4633,
48	      "SJ": 0.4662,
49	      "FK": 0.4573,
50	      "EM": 0.4632,
51	      "LP": 0.308,
52	      "auroc_VC": 0.7444,
53	      "auroc_SJ": 0.7391,
54	      "auroc_FK": 0.7358,
55	      "auroc_EM": 0.7395,
56	      "auroc_LP": 0.7611
57	    },
58	    "llama_conll_n16_seed456": {
59	      "n_instances": 2756,
60	      "n_total": 3453,
61	      "n_gold_empty": 697,
62	      "VC": 0.4722,
63	      "SJ": 0.4734,
64	      "FK": 0.469,
65	      "EM": 0.4752,
66	      "LP": 0.3099,
67	      "auroc_VC": 0.7495,
68	      "auroc_SJ": 0.7428,
69	      "auroc_FK": 0.7408,
70	      "auroc_EM": 0.7444,
71	      "auroc_LP": 0.7628
72	    },
73	    "qwen_scierc_n16_seed42": {
74	      "n_instances": 529,
75	      "n_total": 551,
76	      "n_gold_empty": 22,
77	      "VC": 0.3993,
78	      "SJ": 0.3984,
79	      "FK": 0.2876,
80	      "EM": 0.3386,
81	      "LP": 0.2373,
82	      "auroc_VC": 0.7085,
83	      "auroc_SJ": 0.7205,
84	      "auroc_FK": 0.6348,
85	      "auroc_EM": 0.7837,
86	      "auroc_LP": 0.6096,
87	      "re_n_valid": 397,
88	      "re_FK": 0.2808,
89	      "re_SJ": 0.2766
90	    },
91	    "qwen_scierc_n16_seed123": {
92	      "n_instances": 529,
93	      "n_total": 551,
94	      "n_gold_empty": 22,
95	      "VC": 0.3835,
96	      "SJ": 0.4234,
97	      "FK": 0.2899,
98	      "EM": 0.3437,
99	      "LP": 0.2391,
100	      "auroc_VC": 0.7024,
101	      "auroc_SJ": 0.7352,
102	      "auroc_FK": 0.6292,
103	      "auroc_EM": 0.7878,
104	      "auroc_LP": 0.6045,
105	      "re_n_valid": 397,
106	      "re_FK": 0.3154,
107	      "re_SJ": 0.2672
108	    },
109	    "qwen_scierc_n16_seed456": {
110	      "n_instances": 529,
111	      "n_total": 551,
112	      "n_gold_empty": 22,
113	      "VC": 0.4449,
114	      "SJ": 0.4098,
115	      "FK": 0.2723,
116	      "EM": 0.3363,
117	      "LP": 0.2415,
118	      "auroc_VC": 0.7392,
119	      "auroc_SJ": 0.7367,
120	      "auroc_FK": 0.6157,
121	      "auroc_EM": 0.7848,
122	      "auroc_LP": 0.6054,
123	      "re_n_valid": 397,
124	      "re_FK": 0.2929,
125	      "re_SJ": 0.2835
126	    },
127	    "llama_conll_n8_seed42": {
128	      "n_instances": 2756,
129	      "n_total": 3453,
130	      "n_gold_empty": 697,
131	      "VC": 0.4256,
132	      "SJ": 0.4314,
133	      "FK": 0.4277,
134	      "EM": 0.4306,
135	      "LP": 0.3072,
136	      "auroc_VC": 0.7088,
137	      "auroc_SJ": 0.7039,
138	      "auroc_FK": 0.7026,
139	      "auroc_EM": 0.7046,
140	      "auroc_LP": 0.761
141	    },
142	    "qwen_conll_n8_seed42": {
143	      "n_instances": 2756,
144	      "n_total": 3453,
145	      "n_gold_empty": 697,
146	      "VC": 0.4237,
147	      "SJ": 0.4357,
148	      "FK": 0.3998,
149	      "EM": 0.4507,
150	      "LP": 0.3157,
151	      "auroc_VC": 0.7889,
152	      "auroc_SJ": 0.8008,
153	      "auroc_FK": 0.7741,
154	      "auroc_EM": 0.8156,
155	      "auroc_LP": 0.7532
156	    },
157	    "llama_scierc_n8_seed42": {
158	      "n_instances": 529,
159	      "n_total": 551,
160	      "n_gold_empty": 22,
161	      "VC": 0.373,
162	      "SJ": 0.3096,
163	      "FK": 0.2352,
164	      "EM": 0.2703,
165	      "LP": 0.1503,
166	      "auroc_VC": 0.6877,
167	      "auroc_SJ": 0.6518,
168	      "auroc_FK": 0.6088,
169	      "auroc_EM": 0.6397,
170	      "auroc_LP": 0.5808,
171	      "re_n_valid": 397,
172	      "re_FK": 0.3027,
173	      "re_SJ": 0.2748
174	    },
175	    "qwen_scierc_n8_seed42": {
176	      "n_instances": 529,
177	      "n_total": 551,
178	      "n_gold_empty": 22,
179	      "VC": 0.3792,
180	      "SJ": 0.3599,
181	      "FK": 0.2665,
182	      "EM": 0.2945,
183	      "LP": 0.2052,
184	      "auroc_VC": 0.6627,
185	      "auroc_SJ": 0.65,
186	      "auroc_FK": 0.6019,
187	      "auroc_EM": 0.6138,
188	      "auroc_LP": 0.5778,
189	      "re_n_valid": 397,
190	      "re_FK": 0.2752,
191	      "re_SJ": 0.2503
192	    },
193	    "qwen_scierc_n8_seed123": {
194	      "n_instances": 529,
195	      "n_total": 551,
196	      "n_gold_empty": 22,
197	      "VC": 0.4133,
198	      "SJ": 0.3878,
199	      "FK": 0.2628,
200	      "EM": 0.3135,
201	      "LP": 0.2341,
202	      "auroc_VC": 0.6898,
203	      "auroc_SJ": 0.6813,
204	      "auroc_FK": 0.6183,
205	      "auroc_EM": 0.6439,
206	      "auroc_LP": 0.5898,
207	      "re_n_valid": 397,
208	      "re_FK": 0.2908,
209	      "re_SJ": 0.2486
210	    },
211	    "llama_scierc_n8_seed123": {
212	      "n_instances": 529,
213	      "n_total": 551,
214	      "n_gold_empty": 22,
215	      "VC": 0.4032,
216	      "SJ": 0.3552,
217	      "FK": 0.2897,
218	      "EM": 0.2945,
219	      "LP": 0.197,
220	      "auroc_VC": 0.6954,
221	      "auroc_SJ": 0.6682,
222	      "auroc_FK": 0.6317,
223	      "auroc_EM": 0.6412,
224	      "auroc_LP": 0.5839,
225	      "re_n_valid": 397,
226	      "re_FK": 0.2555,
227	      "re_SJ": 0.2462
228	    },
229	    "llama_conll_n8_seed123": {
230	      "n_instances": 2756,
231	      "n_total": 3453,
232	      "n_gold_empty": 697,
233	      "VC": 0.42,
234	      "SJ": 0.431,
235	      "FK": 0.426,
236	      "EM": 0.428,
237	      "LP": 0.307,
238	      "auroc_VC": 0.703,
239	      "auroc_SJ": 0.701,
240	      "auroc_FK": 0.699,
241	      "auroc_EM": 0.701,
242	      "auroc_LP": 0.76
243	    },
244	    "llama_scierc_n8_seed456": {
245	      "n_instances": 529,
246	      "n_total": 551,
247	      "n_gold_empty": 22,
248	      "VC": 0.3751,
249	      "SJ": 0.3099,
250	      "FK": 0.2422,
251	      "EM": 0.2708,
252	      "LP": 0.1391,
253	      "auroc_VC": 0.6827,
254	      "auroc_SJ": 0.6453,
255	      "auroc_FK": 0.6086,
256	      "auroc_EM": 0.6278,
257	      "auroc_LP": 0.5676,
258	      "re_n_valid": 397,
259	      "re_FK": 0.2791,
260	      "re_SJ": 0.2828
261	    }
262	  }
263	}
264	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "1d98bbcb-75b0-413b-a04c-202c3d5f0384",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/data/analysis_unified_rho_full.json",
      "content": "{\n  \"metadata\": {\n    \"pipeline\": \"unified_gold_filtered\",\n    \"date\": \"2026-05-15\",\n    \"fk_empty_fix\": true,\n    \"gold_filter\": \"exclude instances where len(gold.entities)==0\",\n    \"conll_n_valid\": 2756,\n    \"scierc_n_valid\": 529,\n    \"data_fix_d093\": {\n      \"date\": \"2026-05-15\",\n      \"reason\": \"D093: LLaMA SciERC N=8 entries replaced with exp_018 clean rerun data. Old values from exp_007 pipeline had contaminated VC/EM rho and all AUROC values.\",\n      \"source\": \"multi_seed_stability_table.md (compute_llama_3seed_summary.py)\",\n      \"affected_entries\": [\n        \"llama_scierc_n8_seed42\",\n        \"llama_scierc_n8_seed123\",\n        \"llama_scierc_n8_seed456 (added)\"\n      ],\n      \"three_seed_mean\": {\n        \"SJ\": 0.325,\n        \"FK\": 0.256,\n        \"VC\": 0.384,\n        \"EM\": 0.279,\n        \"LP\": 0.162\n      }\n    }\n  },\n  \"results\": {\n    \"llama_conll_n16_seed42\": {\n      \"n_instances\": 2756,\n      \"n_total\": 3453,\n      \"n_gold_empty\": 697,\n      \"VC\": 0.4746,\n      \"SJ\": 0.4836,\n      \"FK\": 0.4752,\n      \"EM\": 0.4818,\n      \"LP\": 0.3136,\n      \"auroc_VC\": 0.7529,\n      \"auroc_SJ\": 0.7496,\n      \"auroc_FK\": 0.7467,\n      \"auroc_EM\": 0.7508,\n      \"auroc_LP\": 0.7661\n    },\n    \"llama_conll_n16_seed123\": {\n      \"n_instances\": 2756,\n      \"n_total\": 3453,\n      \"n_gold_empty\": 697,\n      \"VC\": 0.4633,\n      \"SJ\": 0.4662,\n      \"FK\": 0.4573,\n      \"EM\": 0.4632,\n      \"LP\": 0.308,\n      \"auroc_VC\": 0.7444,\n      \"auroc_SJ\": 0.7391,\n      \"auroc_FK\": 0.7358,\n      \"auroc_EM\": 0.7395,\n      \"auroc_LP\": 0.7611\n    },\n    \"llama_conll_n16_seed456\": {\n      \"n_instances\": 2756,\n      \"n_total\": 3453,\n      \"n_gold_empty\": 697,\n      \"VC\": 0.4722,\n      \"SJ\": 0.4734,\n      \"FK\": 0.469,\n      \"EM\": 0.4752,\n      \"LP\": 0.3099,\n      \"auroc_VC\": 0.7495,\n      \"auroc_SJ\": 0.7428,\n      \"auroc_FK\": 0.7408,\n      \"auroc_EM\": 0.7444,\n      \"auroc_LP\": 0.7628\n    },\n    \"qwen_scierc_n16_seed42\": {\n      \"n_instances\": 529,\n      \"n_total\": 551,\n      \"n_gold_empty\": 22,\n      \"VC\": 0.3993,\n      \"SJ\": 0.3984,\n      \"FK\": 0.2876,\n      \"EM\": 0.3386,\n      \"LP\": 0.2373,\n      \"auroc_VC\": 0.7085,\n      \"auroc_SJ\": 0.7205,\n      \"auroc_FK\": 0.6348,\n      \"auroc_EM\": 0.7837,\n      \"auroc_LP\": 0.6096,\n      \"re_n_valid\": 397,\n      \"re_FK\": 0.2808,\n      \"re_SJ\": 0.2766\n    },\n    \"qwen_scierc_n16_seed123\": {\n      \"n_instances\": 529,\n      \"n_total\": 551,\n      \"n_gold_empty\": 22,\n      \"VC\": 0.3835,\n      \"SJ\": 0.4234,\n      \"FK\": 0.2899,\n      \"EM\": 0.3437,\n      \"LP\": 0.2391,\n      \"auroc_VC\": 0.7024,\n      \"auroc_SJ\": 0.7352,\n      \"auroc_FK\": 0.6292,\n      \"auroc_EM\": 0.7878,\n      \"auroc_LP\": 0.6045,\n      \"re_n_valid\": 397,\n      \"re_FK\": 0.3154,\n      \"re_SJ\": 0.2672\n    },\n    \"qwen_scierc_n16_seed456\": {\n      \"n_instances\": 529,\n      \"n_total\": 551,\n      \"n_gold_empty\": 22,\n      \"VC\": 0.4449,\n      \"SJ\": 0.4098,\n      \"FK\": 0.2723,\n      \"EM\": 0.3363,\n      \"LP\": 0.2415,\n      \"auroc_VC\": 0.7392,\n      \"auroc_SJ\": 0.7367,\n      \"auroc_FK\": 0.6157,\n      \"auroc_EM\": 0.7848,\n      \"auroc_LP\": 0.6054,\n      \"re_n_valid\": 397,\n      \"re_FK\": 0.2929,\n      \"re_SJ\": 0.2835\n    },\n    \"llama_conll_n8_seed42\": {\n      \"n_instances\": 2756,\n      \"n_total\": 3453,\n      \"n_gold_empty\": 697,\n      \"VC\": 0.4256,\n      \"SJ\": 0.4314,\n      \"FK\": 0.4277,\n      \"EM\": 0.4306,\n      \"LP\": 0.3072,\n      \"auroc_VC\": 0.7088,\n      \"auroc_SJ\": 0.7039,\n      \"auroc_FK\": 0.7026,\n      \"auroc_EM\": 0.7046,\n      \"auroc_LP\": 0.761\n    },\n    \"qwen_conll_n8_seed42\": {\n      \"n_instances\": 2756,\n      \"n_total\": 3453,\n      \"n_gold_empty\": 697,\n      \"VC\": 0.4237,\n      \"SJ\": 0.4357,\n      \"FK\": 0.3998,\n      \"EM\": 0.4507,\n      \"LP\": 0.3157,\n      \"auroc_VC\": 0.7889,\n      \"auroc_SJ\": 0.8008,\n      \"auroc_FK\": 0.7741,\n      \"auroc_EM\": 0.8156,\n      \"auroc_LP\": 0.7532\n    },\n    \"llama_scierc_n8_seed42\": {\n      \"n_instances\": 529,\n      \"n_total\": 551,\n      \"n_gold_empty\": 22,\n      \"VC\": 0.373,\n      \"SJ\": 0.3096,\n      \"FK\": 0.2352,\n      \"EM\": 0.2703,\n      \"LP\": 0.1503,\n      \"auroc_VC\": 0.6877,\n      \"auroc_SJ\": 0.6518,\n      \"auroc_FK\": 0.6088,\n      \"auroc_EM\": 0.6397,\n      \"auroc_LP\": 0.5808,\n      \"re_n_valid\": 397,\n      \"re_FK\": 0.3027,\n      \"re_SJ\": 0.2748\n    },\n    \"qwen_scierc_n8_seed42\": {\n      \"n_instances\": 529,\n      \"n_total\": 551,\n      \"n_gold_empty\": 22,\n      \"VC\": 0.3792,\n      \"SJ\": 0.3599,\n      \"FK\": 0.2665,\n      \"EM\": 0.2945,\n      \"LP\": 0.2052,\n      \"auroc_VC\": 0.6627,\n      \"auroc_SJ\": 0.65,\n      \"auroc_FK\": 0.6019,\n      \"auroc_EM\": 0.6138,\n      \"auroc_LP\": 0.5778,\n      \"re_n_valid\": 397,\n      \"re_FK\": 0.2752,\n      \"re_SJ\": 0.2503\n    },\n    \"qwen_scierc_n8_seed123\": {\n      \"n_instances\": 529,\n      \"n_total\": 551,\n      \"n_gold_empty\": 22,\n      \"VC\": 0.4133,\n      \"SJ\": 0.3878,\n      \"FK\": 0.2628,\n      \"EM\": 0.3135,\n      \"LP\": 0.2341,\n      \"auroc_VC\": 0.6898,\n      \"auroc_SJ\": 0.6813,\n      \"auroc_FK\": 0.6183,\n      \"auroc_EM\": 0.6439,\n      \"auroc_LP\": 0.5898,\n      \"re_n_valid\": 397,\n      \"re_FK\": 0.2908,\n      \"re_SJ\": 0.2486\n    },\n    \"llama_scierc_n8_seed123\": {\n      \"n_instances\": 529,\n      \"n_total\": 551,\n      \"n_gold_empty\": 22,\n      \"VC\": 0.4032,\n      \"SJ\": 0.3552,\n      \"FK\": 0.2897,\n      \"EM\": 0.2945,\n      \"LP\": 0.197,\n      \"auroc_VC\": 0.6954,\n      \"auroc_SJ\": 0.6682,\n      \"auroc_FK\": 0.6317,\n      \"auroc_EM\": 0.6412,\n      \"auroc_LP\": 0.5839,\n      \"re_n_valid\": 397,\n      \"re_FK\": 0.2555,\n      \"re_SJ\": 0.2462\n    },\n    \"llama_conll_n8_seed123\": {\n      \"n_instances\": 2756,\n      \"n_total\": 3453,\n      \"n_gold_empty\": 697,\n      \"VC\": 0.42,\n      \"SJ\": 0.431,\n      \"FK\": 0.426,\n      \"EM\": 0.428,\n      \"LP\": 0.307,\n      \"auroc_VC\": 0.703,\n      \"auroc_SJ\": 0.701,\n      \"auroc_FK\": 0.699,\n      \"auroc_EM\": 0.701,\n      \"auroc_LP\": 0.76\n    },\n    \"llama_scierc_n8_seed456\": {\n      \"n_instances\": 529,\n      \"n_total\": 551,\n      \"n_gold_empty\": 22,\n      \"VC\": 0.3751,\n      \"SJ\": 0.3099,\n      \"FK\": 0.2422,\n      \"EM\": 0.2708,\n      \"LP\": 0.1391,\n      \"auroc_VC\": 0.6827,\n      \"auroc_SJ\": 0.6453,\n      \"auroc_FK\": 0.6086,\n      \"auroc_EM\": 0.6278,\n      \"auroc_LP\": 0.5676,\n      \"re_n_valid\": 397,\n      \"re_FK\": 0.2791,\n      \"re_SJ\": 0.2828\n    }\n  }\n}\n",
      "numLines": 264,
      "startLine": 1,
      "totalLines": 264
    }
  }
}
```

</details>

---

### Assistant

_source line 31_

<details><summary>Logged reasoning block</summary>

```text
Now I have the key data. Let me also check the paper's experiments tables and FewNERD data to see if there are any higher ρ values. Let me also look at the MF4v2 (Qwen3-8B-FT) data which is the newer pipeline, and any other experiments that might have higher ρ values.

Let me now search for AUROC 0.82 mentioned in the abstract, and check the full unified rho data more carefully.

From the unified rho data, the highest ρ values I see are:


Compiling the performance metrics across different seeds and datasets... Now I'm looking at the performance metrics for Qwen across both datasets, and I'm noticing that the absolute maximum correlation coefficient across everything is SJ=0.4836 from LLaMA CoNLL with N=16 and seed42, though EM reaches nearly as high at 0.4818 for the same configuration.

The abstract claims ρ values up to 0.45, but the actual maximum is 0.4836, so there's some understatement there. I'm also cross-referencing the alpha_crit_table which shows soft_jaccard ρ ranging from 0.31–0.46 for the MF4v2 data (Qwen3-8B-FT), and I need to verify whether there are FewNERD-specific correlation values I'm missing, plus track down what the AUROC 0.82 mentioned in the abstract corresponds to—it looks like it might align with the qwen_conll_n8_seed42 result of 0.8156.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "ed34a197-009e-40b9-b0ed-1ac1ecde40ab",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GQ3V4ZZXkfYWcsz7vu1GG4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11090,
      "cache_read_input_tokens": 32538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11090
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

_source line 32_

The highest ρ I see so far is SJ=0.4836 (LLaMA CoNLL N=16 seed42). Let me also check the paper's experiment tables and FewNERD-specific data.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "021ada25-2f72-44c9-a8c2-ff1da9bb5761",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GQ3V4ZZXkfYWcsz7vu1GG4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11090,
      "cache_read_input_tokens": 32538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11090
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

_source line 33_

<details open><summary>🔧 Tool call — Read · `toolu_01AjNr2tMGzjWbkMAkp4RYH6`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments_main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "d4438881-67c1-4f61-8d92-70091818475c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GQ3V4ZZXkfYWcsz7vu1GG4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11090,
      "cache_read_input_tokens": 32538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11090
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

_source line 34 · 2026-05-21T12:00:59.406Z_

<details><summary>↩ Tool result · `toolu_01AjNr2tMGzjWbkMAkp4RYH6`</summary>

```text
1	\section{Experiments}\label{sec:experiments}
2	
3	\subsection{Experimental Setup}\label{sec:setup}
4	
5	\paragraph{Datasets.}
6	We evaluate on four English NER benchmarks spanning a difficulty gradient.
7	\textbf{SciERC} \cite{luan2018scierc} (551 test instances, 6 entity types) is the primary medium-difficulty test bed (${\approx}$65\% F1).
8	\textbf{Few-NERD} \cite{ding2021fewnerd} (INTRA coarse; 37{,}648 instances, 8 entity types, ${\approx}$75\% F1) provides a low-degeneracy contrast where LP selection succeeds (\S\ref{sec:selection_gap}).
9	\textbf{CoNLL-2003} \cite{tjongkimsang2003conll} (3{,}453 test sentences, 4 entity types, ${\approx}$91\% F1) serves as a ceiling-effect control.
10	\textbf{WNUT-17} \cite{derczynski2017wnut} (1{,}287 social media instances, 51\% zero F1) probes the signal-collapse boundary.
11	
12	\paragraph{Models and sampling.}
13	\textbf{Qwen3-8B} and \textbf{LLaMA-3.1-8B-Instruct} are LoRA fine-tuned using LLaMA Factory \cite{zheng2024llamafactory} (Appendix~\ref{app:training}; Few-NERD uses 3 epochs vs.\ 5 for others; Appendix~\ref{app:epoch_confound}).
14	$N{=}8$ samples at $T{=}1.0$ (primary) with vLLM constrained decoding \cite{willard2023guided}; $N{=}16$ for scaling (Appendix~\ref{app:n_scaling}).
15	
16	%% ============================================================
17	\subsection{Quality Estimation Results}\label{sec:qe_results}
18	
19	\begin{table*}[t]
20	\centering
21	\small
22	\caption{NER quality estimation ($\rho$ and AUROC; $N{=}8$, primary seed${=}42$; 3-seed $\sigma{\leq}0.026$ in Table~\ref{tab:multiseed}). AUROC binarizes at per-dataset median F1. Best in \textbf{bold}. RE in Appendix~\ref{app:re_extension}; $N{=}16$ in Table~\ref{tab:robustness}.}
23	\label{tab:quality_estimation}
24	\begin{tabular}{ll cc cc cc}
25	\toprule
26	& & \multicolumn{2}{c}{\textbf{SciERC}} & \multicolumn{2}{c}{\textbf{CoNLL (Qwen)}} & \multicolumn{2}{c}{\textbf{CoNLL (LLaMA)}} \\
27	\cmidrule(lr){3-4} \cmidrule(lr){5-6} \cmidrule(lr){7-8}
28	Signal & Family & $\rho$ & AUC & $\rho$ & AUC & $\rho$ & AUC \\
29	\midrule
30	VC & Structural & \textbf{.379} & .684 & .424 & .789 & .426 & .709 \\
31	SJ  & Structural & .360 & .692 & .436 & .801 & \textbf{.431} & .704 \\
32	FK & Surface & .267 & .629 & .400 & .774 & .428 & .703 \\
33	EM  & Surface    & .295 & \textbf{.749} & \textbf{.451} & \textbf{.816} & \textbf{.431} & .705 \\
34	\midrule
35	LP     & Model      & .205 & .578 & .316 & .753 & .307 & \textbf{.761} \\
36	\bottomrule
37	\end{tabular}
38	\end{table*}
39	
40	Table~\ref{tab:quality_estimation} presents $\rho$ and AUROC for five signals across tasks and models.
41	
42	\paragraph{Signal rankings are difficulty-dependent.}
43	On SciERC, structural signals lead (VC $\rho{=}0.379$, SJ $0.360$) over LP ($0.205$); bootstrap CIs confirm the gap ($\Delta\rho{=}{+}0.155$; Appendix~\ref{app:bootstrap_signal}).
44	On CoNLL (F1${\approx}$0.91), EM leads both $\rho$ and AUROC ($0.816$).
45	At the signal-collapse boundary (WNUT-17, F1${\approx}$42\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\rho{=}0.724$ at $N{=}16$, but conditional $\rho{=}0.038$; Table~\ref{tab:wnut}); LP shows the reverse (conditional $\rho{=}0.350$; Figure~\ref{fig:signal_heatmap}).
46	
47	%% ============================================================
48	\subsection{Cross-Dataset Contrast: Few-NERD}\label{sec:fewnerd}
49	
50	\begin{table}[t]
51	\centering
52	\small
53	\caption{LP selection across datasets (Qwen3-8B, $N{=}8$, $T{=}1.0$, gold-filtered). Few-NERD/CoNLL: 3-seed means; SciERC: single-seed. $p$: paired bootstrap.}
54	\label{tab:fewnerd}
55	\resizebox{\columnwidth}{!}{%
56	\begin{tabular}{@{}lrccccr@{}}
57	\toprule
58	Dataset & $n$ & Greedy & Degen.\% & LP $\rho$ & LP $\Delta$ & $p$ \\
59	\midrule
60	WNUT-17 & 1{,}287 & .452 & 67.9\% & $-$.446 & $-$0.45\,pp & .72 \\
61	CoNLL & 2{,}756 & .908 & 61.7\% & .302 & $-$0.85\,pp & 1.0 \\
62	SciERC & 529 & .644 & 17.8\% & .205 & $+$0.61\,pp & .193 \\
63	Few-NERD & 32{,}565 & .748 & 13.0\% & .220 & $\mathbf{+1.39}$\,pp & ${<}.001$ \\
64	\bottomrule
65	\end{tabular}}
66	\end{table}
67	
68	Few-NERD (Table~\ref{tab:fewnerd}) confirms LP selection at low degeneracy ($+1.39$~pp, $p{<}0.001$; structural signals degrade: VC $-1.79$, SJ $-2.14$~pp), with LP 50$\times$ more seed-stable ($\sigma{=}0.04$ vs.\ SJ $2.02$~pp), generalizing to LLaMA (Table~\ref{tab:cross_selection}). Training convergence modulates degeneracy (5-epoch: $31$\%, halving LP gains; Appendix~\ref{app:epoch_confound}).
69	
70	\paragraph{Degeneracy alone does not predict LP direction.}
71	Degeneracy does not predict LP gain across 23 configurations ($\rho{=}0.052$, $p{=}0.81$; post-hoc: 80\% power requires $n{\approx}85$; Figure~\ref{fig:degeneracy_scatter}), though it co-varies with LP within fixed settings ($\rho{=}{-}0.881$; Appendix~\ref{app:per_type_lp}).
72	
73	\begin{figure}[t]
74	\centering
75	\includegraphics[width=\columnwidth]{figures/fig_degeneracy_lp_scatter.pdf}
76	\caption{Instance degeneracy vs.\ LP selection gain across 23 configurations ($N{=}8$; $\rho{=}0.052$, $p{=}0.81$). Within Few-NERD per-entity-type ($\rho{=}{-}0.881$; Appendix~\ref{app:per_type_lp}), degeneracy predicts LP gain when alignment is held constant.}
77	\label{fig:degeneracy_scatter}
78	\end{figure}
79	
80	Structural signals remain negative regardless of sample budget; $N$-scaling analyses are in Appendix~\ref{app:n_scaling}.
81	
82	%% ============================================================
83	\subsection{Robustness}\label{sec:robustness_main}
84	
85	Signal rankings are robust across temperatures, seeds ($W{=}1.0$), and $N$ (Table~\ref{tab:robustness}); NER calibration is reasonable (ECE 0.069--0.096; Appendix~\ref{app:calibration}).
86	
87	\paragraph{Scale and controlled ablations.}
88	Qwen3-4B QE is comparable to 8B ($|\Delta\rho|{=}0.042$; Table~\ref{tab:scale_ablation_app}), yet selection remains below greedy.
89	LoRA rank${=}8$ lowers degeneracy to 7.2\% but LP stays below greedy, confirming both conditions are independently necessary; supervised classifiers, DeBERTa verifier, and hidden-state probes also fail (Appendix~\ref{app:supervised_combination}, \ref{app:hidden_probe}).
90	
91	%% ============================================================
92	\subsection{Prescriptive Results}\label{sec:prescriptive}
93	
94	\paragraph{Entity-level construction.}
95	We aggregate entities across samples, retaining those exceeding $\theta{=}2/N$, with LP-weighted or uniform scoring ($\theta$ stable in $[0.15, 0.35]$; Appendix~\ref{app:theta_sweep}). In zero-shot, LP-weighting is necessary (SciERC $+1.5$\,pp; Appendix~\ref{app:cross_scale}).
96	
97	\begin{table}[t]
98	\centering
99	\small
100	\caption{Entity construction vs.\ greedy ($\Delta$ macro F1; $N{=}8$, $T{=}1.0$, Qwen3-8B, multi-seed mean${\pm}\sigma$). $\theta{=}2/N$. $p$: paired bootstrap vs.\ greedy. $^\dagger$Survives Holm--Bonferroni within construction family ($k{=}10$; global $k{=}57$ in Appendix~\ref{app:holm}). $^\ddagger$LP-weighted not computed.}
101	\label{tab:entity_construction}
102	\resizebox{\columnwidth}{!}{%
103	\begin{tabular}{@{}llcccc@{}}
104	\toprule
105	Dataset & Wt. & Greedy & Constr. & $\Delta$ & $p$ \\
106	\midrule
107	SciERC & LP & $.646{\pm}.002$ & $\mathbf{.656{\pm}.003}$ & $+1.02{\pm}0.49$\,pp & .004 \\
108	       & Unif. & $.646{\pm}.002$ & $.653{\pm}.006$ & $+0.74{\pm}0.71$\,pp & .023 \\
109	\addlinespace
110	Few-NERD & LP & $.748$ & $\mathbf{.762{\pm}.005}$ & $+1.40{\pm}0.51$\,pp & ${<}.001^\dagger$ \\
111	         & Unif. & $.748$ & $.756{\pm}.006$ & $+0.74{\pm}0.58$\,pp & .003 \\
112	\addlinespace
113	CoNLL$^\ddagger$ & Unif. & .908 & .904 & $-0.39$\,pp & n.s. \\
114	\bottomrule
115	\end{tabular}}
116	\end{table}
117	
118	LP-weighted construction improves on Few-NERD ($+1.40{\pm}0.51$\,pp, $p{<}0.001$; Holm $p_{\text{adj}}{=}0.006$, $k{=}10$) and SciERC ($+1.02{\pm}0.49$\,pp, $p{=}0.004$, $p_{\text{adj}}{=}0.20$), recovering 8--11\% of oracle headroom; CoNLL shows no gain ($-0.39$\,pp), consistent with high degeneracy.
119	Gains require both low degeneracy \textit{and} sufficient oracle headroom (Few-NERD: $D{=}13$\%, headroom${=}12.4$\,pp).\footnote{Holm--Bonferroni correction within families: selection $k{=}19$, construction $k{=}10$, signal $k{=}9$. Under global $k{=}57$, no claim survives ($p_{\text{adj}}{=}0.055$ for Few-NERD); see Appendix~\ref{app:holm}.}
120	
121	\paragraph{Complementary strategies.}
122	Construction and LP selection are complementary, governed by within-instance LP alignment $\rho_{\text{adj}}$ (Few-NERD $0.516$ favors both; SciERC $0.167$ favors construction only).
123	QE signals also support selective prediction: at 80\% coverage, filtering yields $+5$--$8$\,pp F1 (AUPRC 0.70--0.92; Table~\ref{tab:cross_selection}).
124	
125	\phantomsection\label{sec:selection_results}
126	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "73bb8860-87d9-4067-a0e3-badd12af04a0",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments_main.tex",
      "content": "\\section{Experiments}\\label{sec:experiments}\n\n\\subsection{Experimental Setup}\\label{sec:setup}\n\n\\paragraph{Datasets.}\nWe evaluate on four English NER benchmarks spanning a difficulty gradient.\n\\textbf{SciERC} \\cite{luan2018scierc} (551 test instances, 6 entity types) is the primary medium-difficulty test bed (${\\approx}$65\\% F1).\n\\textbf{Few-NERD} \\cite{ding2021fewnerd} (INTRA coarse; 37{,}648 instances, 8 entity types, ${\\approx}$75\\% F1) provides a low-degeneracy contrast where LP selection succeeds (\\S\\ref{sec:selection_gap}).\n\\textbf{CoNLL-2003} \\cite{tjongkimsang2003conll} (3{,}453 test sentences, 4 entity types, ${\\approx}$91\\% F1) serves as a ceiling-effect control.\n\\textbf{WNUT-17} \\cite{derczynski2017wnut} (1{,}287 social media instances, 51\\% zero F1) probes the signal-collapse boundary.\n\n\\paragraph{Models and sampling.}\n\\textbf{Qwen3-8B} and \\textbf{LLaMA-3.1-8B-Instruct} are LoRA fine-tuned using LLaMA Factory \\cite{zheng2024llamafactory} (Appendix~\\ref{app:training}; Few-NERD uses 3 epochs vs.\\ 5 for others; Appendix~\\ref{app:epoch_confound}).\n$N{=}8$ samples at $T{=}1.0$ (primary) with vLLM constrained decoding \\cite{willard2023guided}; $N{=}16$ for scaling (Appendix~\\ref{app:n_scaling}).\n\n%% ============================================================\n\\subsection{Quality Estimation Results}\\label{sec:qe_results}\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{NER quality estimation ($\\rho$ and AUROC; $N{=}8$, primary seed${=}42$; 3-seed $\\sigma{\\leq}0.026$ in Table~\\ref{tab:multiseed}). AUROC binarizes at per-dataset median F1. Best in \\textbf{bold}. RE in Appendix~\\ref{app:re_extension}; $N{=}16$ in Table~\\ref{tab:robustness}.}\n\\label{tab:quality_estimation}\n\\begin{tabular}{ll cc cc cc}\n\\toprule\n& & \\multicolumn{2}{c}{\\textbf{SciERC}} & \\multicolumn{2}{c}{\\textbf{CoNLL (Qwen)}} & \\multicolumn{2}{c}{\\textbf{CoNLL (LLaMA)}} \\\\\n\\cmidrule(lr){3-4} \\cmidrule(lr){5-6} \\cmidrule(lr){7-8}\nSignal & Family & $\\rho$ & AUC & $\\rho$ & AUC & $\\rho$ & AUC \\\\\n\\midrule\nVC & Structural & \\textbf{.379} & .684 & .424 & .789 & .426 & .709 \\\\\nSJ  & Structural & .360 & .692 & .436 & .801 & \\textbf{.431} & .704 \\\\\nFK & Surface & .267 & .629 & .400 & .774 & .428 & .703 \\\\\nEM  & Surface    & .295 & \\textbf{.749} & \\textbf{.451} & \\textbf{.816} & \\textbf{.431} & .705 \\\\\n\\midrule\nLP     & Model      & .205 & .578 & .316 & .753 & .307 & \\textbf{.761} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\nTable~\\ref{tab:quality_estimation} presents $\\rho$ and AUROC for five signals across tasks and models.\n\n\\paragraph{Signal rankings are difficulty-dependent.}\nOn SciERC, structural signals lead (VC $\\rho{=}0.379$, SJ $0.360$) over LP ($0.205$); bootstrap CIs confirm the gap ($\\Delta\\rho{=}{+}0.155$; Appendix~\\ref{app:bootstrap_signal}).\nOn CoNLL (F1${\\approx}$0.91), EM leads both $\\rho$ and AUROC ($0.816$).\nAt the signal-collapse boundary (WNUT-17, F1${\\approx}$42\\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\\rho{=}0.724$ at $N{=}16$, but conditional $\\rho{=}0.038$; Table~\\ref{tab:wnut}); LP shows the reverse (conditional $\\rho{=}0.350$; Figure~\\ref{fig:signal_heatmap}).\n\n%% ============================================================\n\\subsection{Cross-Dataset Contrast: Few-NERD}\\label{sec:fewnerd}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{LP selection across datasets (Qwen3-8B, $N{=}8$, $T{=}1.0$, gold-filtered). Few-NERD/CoNLL: 3-seed means; SciERC: single-seed. $p$: paired bootstrap.}\n\\label{tab:fewnerd}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lrccccr@{}}\n\\toprule\nDataset & $n$ & Greedy & Degen.\\% & LP $\\rho$ & LP $\\Delta$ & $p$ \\\\\n\\midrule\nWNUT-17 & 1{,}287 & .452 & 67.9\\% & $-$.446 & $-$0.45\\,pp & .72 \\\\\nCoNLL & 2{,}756 & .908 & 61.7\\% & .302 & $-$0.85\\,pp & 1.0 \\\\\nSciERC & 529 & .644 & 17.8\\% & .205 & $+$0.61\\,pp & .193 \\\\\nFew-NERD & 32{,}565 & .748 & 13.0\\% & .220 & $\\mathbf{+1.39}$\\,pp & ${<}.001$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nFew-NERD (Table~\\ref{tab:fewnerd}) confirms LP selection at low degeneracy ($+1.39$~pp, $p{<}0.001$; structural signals degrade: VC $-1.79$, SJ $-2.14$~pp), with LP 50$\\times$ more seed-stable ($\\sigma{=}0.04$ vs.\\ SJ $2.02$~pp), generalizing to LLaMA (Table~\\ref{tab:cross_selection}). Training convergence modulates degeneracy (5-epoch: $31$\\%, halving LP gains; Appendix~\\ref{app:epoch_confound}).\n\n\\paragraph{Degeneracy alone does not predict LP direction.}\nDegeneracy does not predict LP gain across 23 configurations ($\\rho{=}0.052$, $p{=}0.81$; post-hoc: 80\\% power requires $n{\\approx}85$; Figure~\\ref{fig:degeneracy_scatter}), though it co-varies with LP within fixed settings ($\\rho{=}{-}0.881$; Appendix~\\ref{app:per_type_lp}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_degeneracy_lp_scatter.pdf}\n\\caption{Instance degeneracy vs.\\ LP selection gain across 23 configurations ($N{=}8$; $\\rho{=}0.052$, $p{=}0.81$). Within Few-NERD per-entity-type ($\\rho{=}{-}0.881$; Appendix~\\ref{app:per_type_lp}), degeneracy predicts LP gain when alignment is held constant.}\n\\label{fig:degeneracy_scatter}\n\\end{figure}\n\nStructural signals remain negative regardless of sample budget; $N$-scaling analyses are in Appendix~\\ref{app:n_scaling}.\n\n%% ============================================================\n\\subsection{Robustness}\\label{sec:robustness_main}\n\nSignal rankings are robust across temperatures, seeds ($W{=}1.0$), and $N$ (Table~\\ref{tab:robustness}); NER calibration is reasonable (ECE 0.069--0.096; Appendix~\\ref{app:calibration}).\n\n\\paragraph{Scale and controlled ablations.}\nQwen3-4B QE is comparable to 8B ($|\\Delta\\rho|{=}0.042$; Table~\\ref{tab:scale_ablation_app}), yet selection remains below greedy.\nLoRA rank${=}8$ lowers degeneracy to 7.2\\% but LP stays below greedy, confirming both conditions are independently necessary; supervised classifiers, DeBERTa verifier, and hidden-state probes also fail (Appendix~\\ref{app:supervised_combination}, \\ref{app:hidden_probe}).\n\n%% ============================================================\n\\subsection{Prescriptive Results}\\label{sec:prescriptive}\n\n\\paragraph{Entity-level construction.}\nWe aggregate entities across samples, retaining those exceeding $\\theta{=}2/N$, with LP-weighted or uniform scoring ($\\theta$ stable in $[0.15, 0.35]$; Appendix~\\ref{app:theta_sweep}). In zero-shot, LP-weighting is necessary (SciERC $+1.5$\\,pp; Appendix~\\ref{app:cross_scale}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Entity construction vs.\\ greedy ($\\Delta$ macro F1; $N{=}8$, $T{=}1.0$, Qwen3-8B, multi-seed mean${\\pm}\\sigma$). $\\theta{=}2/N$. $p$: paired bootstrap vs.\\ greedy. $^\\dagger$Survives Holm--Bonferroni within construction family ($k{=}10$; global $k{=}57$ in Appendix~\\ref{app:holm}). $^\\ddagger$LP-weighted not computed.}\n\\label{tab:entity_construction}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\nDataset & Wt. & Greedy & Constr. & $\\Delta$ & $p$ \\\\\n\\midrule\nSciERC & LP & $.646{\\pm}.002$ & $\\mathbf{.656{\\pm}.003}$ & $+1.02{\\pm}0.49$\\,pp & .004 \\\\\n       & Unif. & $.646{\\pm}.002$ & $.653{\\pm}.006$ & $+0.74{\\pm}0.71$\\,pp & .023 \\\\\n\\addlinespace\nFew-NERD & LP & $.748$ & $\\mathbf{.762{\\pm}.005}$ & $+1.40{\\pm}0.51$\\,pp & ${<}.001^\\dagger$ \\\\\n         & Unif. & $.748$ & $.756{\\pm}.006$ & $+0.74{\\pm}0.58$\\,pp & .003 \\\\\n\\addlinespace\nCoNLL$^\\ddagger$ & Unif. & .908 & .904 & $-0.39$\\,pp & n.s. \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nLP-weighted construction improves on Few-NERD ($+1.40{\\pm}0.51$\\,pp, $p{<}0.001$; Holm $p_{\\text{adj}}{=}0.006$, $k{=}10$) and SciERC ($+1.02{\\pm}0.49$\\,pp, $p{=}0.004$, $p_{\\text{adj}}{=}0.20$), recovering 8--11\\% of oracle headroom; CoNLL shows no gain ($-0.39$\\,pp), consistent with high degeneracy.\nGains require both low degeneracy \\textit{and} sufficient oracle headroom (Few-NERD: $D{=}13$\\%, headroom${=}12.4$\\,pp).\\footnote{Holm--Bonferroni correction within families: selection $k{=}19$, construction $k{=}10$, signal $k{=}9$. Under global $k{=}57$, no claim survives ($p_{\\text{adj}}{=}0.055$ for Few-NERD); see Appendix~\\ref{app:holm}.}\n\n\\paragraph{Complementary strategies.}\nConstruction and LP selection are complementary, governed by within-instance LP alignment $\\rho_{\\text{adj}}$ (Few-NERD $0.516$ favors both; SciERC $0.167$ favors construction only).\nQE signals also support selective prediction: at 80\\% coverage, filtering yields $+5$--$8$\\,pp F1 (AUPRC 0.70--0.92; Table~\\ref{tab:cross_selection}).\n\n\\phantomsection\\label{sec:selection_results}\n",
      "numLines": 126,
      "startLine": 1,
      "totalLines": 126
    }
  }
}
```

</details>

---

### Tool call

_source line 35_

<details open><summary>🔧 Tool call — Read · `toolu_013AVy5CXUTHMwsUA879c9dc`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/single_signal.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "74222422-3705-4585-a10a-d676c4d68363",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GQ3V4ZZXkfYWcsz7vu1GG4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11090,
      "cache_read_input_tokens": 32538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11090
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

_source line 36 · 2026-05-21T12:01:00.343Z_

<details><summary>↩ Tool result · `toolu_013AVy5CXUTHMwsUA879c9dc`</summary>

```text
1	\section{Where Single-Signal Selection Fails}\label{sec:selection_gap}
2	
3	\paragraph{Definitional vs.\ empirical.}
4	We decompose the correlation-selection gap into two layers.
5	The first is structural: four of five signals are instance-level aggregates that assign identical scores to all $N$ candidates from a given input (\S\ref{sec:formulation}), so they estimate quality across inputs but cannot rank candidates within an instance---selection failure is a design property, not an empirical finding.
6	The second layer is empirical and constitutes the core diagnostic: LP---the only per-sample signal---suffers compression under constrained decoding, with 60\% of SciERC instances showing within-instance LP range below 0.041 nats (Appendix~\ref{app:logprob_ties}), effectively eliminating the variation needed for sample discrimination. Even where LP varies, selection gains depend on LP-quality alignment rather than degeneracy alone.
7	Cross-instance $\rho$ (Table~\ref{tab:quality_estimation}) is attenuated by varying instance difficulty; within-instance $\rho$ directly measures whether LP discriminates candidates for a fixed input, making it the relevant predictor of selection success.
8	
9	\begin{table}[t]
10	\centering
11	\small
12	\caption{Best-of-$N$ selection (macro F1) on SciERC ($N{=}8$, $T{=}1.0$, 2-seed mean${\pm}\sigma$). LP is per-sample; others use consensus-proximity. $^\dagger$One score per input.}
13	\label{tab:selection}
14	\begin{tabular}{lcc}
15	\toprule
16	Method & NER F1 & $p$ \\
17	\midrule
18	Oracle & $0.775 \pm 0.001$ & --- \\
19	Greedy ($T{=}0$) & $0.645 \pm 0.001$ & --- \\
20	\midrule
21	LP           & $\mathbf{0.647} \pm 0.005$ & .29 \\
22	SJ           & $0.646 \pm 0.002$ & .67 \\
23	FK           & $0.646 \pm 0.001$ & .79 \\
24	EM           & $0.637 \pm 0.001$ & n/a$^\dagger$ \\
25	VC           & $0.623 \pm 0.004$ & n/a$^\dagger$ \\
26	\midrule
27	Random       & $0.610 \pm 0.003$ & --- \\
28	\bottomrule
29	\end{tabular}
30	\end{table}
31	
32	\begin{figure}[t]
33	\centering
34	\includegraphics[width=\columnwidth]{fig_selection_gap}
35	\caption{Correlation-selection gap on SciERC ($N{=}8$, $T{=}1.0$). Bars: QE $\rho$; line: $\Delta$F1 vs.\ greedy (3-seed mean). Despite $\rho$ up to 0.38, no signal outperforms greedy ($p{>}0.05$). Dashed green: oracle ($+13.0$\,pp); dotted gray: random.}
36	\label{fig:selection_gap}
37	\end{figure}
38	
39	Despite $\rho$ up to 0.38, no signal outperforms greedy on SciERC (Table~\ref{tab:selection}; Figure~\ref{fig:selection_gap}); the oracle reveals 13.0\,pp headroom, but LP achieves $+0.2$\,pp ($p{=}0.29$), below MDE (${\approx}$1.5\,pp; $n{=}529$).
40	The pattern holds across CoNLL and WNUT-17 (Table~\ref{tab:cross_selection}).
41	Few-NERD provides the definitive contrast: LP achieves $+1.39$\,pp ($p{<}0.001$; Holm $p_{\text{adj}}{=}0.019$, selection family $k{=}19$) at low degeneracy (13.0\% vs.\ 17.8--67.9\%), while structural signals still degrade (VC $-1.79$, SJ $-2.14$\,pp; \S\ref{sec:fewnerd}).
42	
43	\paragraph{Diagnostic cascade.}
44	We identify a cascade rather than independent factors:
45	(1)~instance degeneracy sets the ceiling on possible improvement (SciERC 17.8\%, CoNLL 61.7\%);
46	(2)~within non-degenerate instances, oracle headroom determines the opportunity (CoNLL ${\approx}4$\,pp vs.\ SciERC 13.0\,pp);
47	(3)~LP compression limits exploitation of that opportunity (Few-NERD within-instance $\rho{\approx}0.5$--$0.7$ vs.\ SciERC $\rho{\approx}0.26$).
48	We did not find evidence that degeneracy alone predicts LP gain across datasets ($\rho{=}0.052$, $n{=}23$, $p{=}0.81$; post-hoc power: 80\% power requires $n{\approx}85$ for $\rho{=}0.3$; Figure~\ref{fig:degeneracy_scatter}), though degeneracy co-varies with LP within fixed settings ($\rho{=}{-}0.881$; Appendix~\ref{app:per_type_lp}).
49	The cascade stages interact rather than combining into a predictive model ($R^2{<}0$); each is supported by controlled ablations (\S\ref{sec:fewnerd}, \S\ref{sec:discussion}).
50	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "03b2d7eb-f2b8-40ea-a1ae-428ca4e39029",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/single_signal.tex",
      "content": "\\section{Where Single-Signal Selection Fails}\\label{sec:selection_gap}\n\n\\paragraph{Definitional vs.\\ empirical.}\nWe decompose the correlation-selection gap into two layers.\nThe first is structural: four of five signals are instance-level aggregates that assign identical scores to all $N$ candidates from a given input (\\S\\ref{sec:formulation}), so they estimate quality across inputs but cannot rank candidates within an instance---selection failure is a design property, not an empirical finding.\nThe second layer is empirical and constitutes the core diagnostic: LP---the only per-sample signal---suffers compression under constrained decoding, with 60\\% of SciERC instances showing within-instance LP range below 0.041 nats (Appendix~\\ref{app:logprob_ties}), effectively eliminating the variation needed for sample discrimination. Even where LP varies, selection gains depend on LP-quality alignment rather than degeneracy alone.\nCross-instance $\\rho$ (Table~\\ref{tab:quality_estimation}) is attenuated by varying instance difficulty; within-instance $\\rho$ directly measures whether LP discriminates candidates for a fixed input, making it the relevant predictor of selection success.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Best-of-$N$ selection (macro F1) on SciERC ($N{=}8$, $T{=}1.0$, 2-seed mean${\\pm}\\sigma$). LP is per-sample; others use consensus-proximity. $^\\dagger$One score per input.}\n\\label{tab:selection}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & NER F1 & $p$ \\\\\n\\midrule\nOracle & $0.775 \\pm 0.001$ & --- \\\\\nGreedy ($T{=}0$) & $0.645 \\pm 0.001$ & --- \\\\\n\\midrule\nLP           & $\\mathbf{0.647} \\pm 0.005$ & .29 \\\\\nSJ           & $0.646 \\pm 0.002$ & .67 \\\\\nFK           & $0.646 \\pm 0.001$ & .79 \\\\\nEM           & $0.637 \\pm 0.001$ & n/a$^\\dagger$ \\\\\nVC           & $0.623 \\pm 0.004$ & n/a$^\\dagger$ \\\\\n\\midrule\nRandom       & $0.610 \\pm 0.003$ & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_selection_gap}\n\\caption{Correlation-selection gap on SciERC ($N{=}8$, $T{=}1.0$). Bars: QE $\\rho$; line: $\\Delta$F1 vs.\\ greedy (3-seed mean). Despite $\\rho$ up to 0.38, no signal outperforms greedy ($p{>}0.05$). Dashed green: oracle ($+13.0$\\,pp); dotted gray: random.}\n\\label{fig:selection_gap}\n\\end{figure}\n\nDespite $\\rho$ up to 0.38, no signal outperforms greedy on SciERC (Table~\\ref{tab:selection}; Figure~\\ref{fig:selection_gap}); the oracle reveals 13.0\\,pp headroom, but LP achieves $+0.2$\\,pp ($p{=}0.29$), below MDE (${\\approx}$1.5\\,pp; $n{=}529$).\nThe pattern holds across CoNLL and WNUT-17 (Table~\\ref{tab:cross_selection}).\nFew-NERD provides the definitive contrast: LP achieves $+1.39$\\,pp ($p{<}0.001$; Holm $p_{\\text{adj}}{=}0.019$, selection family $k{=}19$) at low degeneracy (13.0\\% vs.\\ 17.8--67.9\\%), while structural signals still degrade (VC $-1.79$, SJ $-2.14$\\,pp; \\S\\ref{sec:fewnerd}).\n\n\\paragraph{Diagnostic cascade.}\nWe identify a cascade rather than independent factors:\n(1)~instance degeneracy sets the ceiling on possible improvement (SciERC 17.8\\%, CoNLL 61.7\\%);\n(2)~within non-degenerate instances, oracle headroom determines the opportunity (CoNLL ${\\approx}4$\\,pp vs.\\ SciERC 13.0\\,pp);\n(3)~LP compression limits exploitation of that opportunity (Few-NERD within-instance $\\rho{\\approx}0.5$--$0.7$ vs.\\ SciERC $\\rho{\\approx}0.26$).\nWe did not find evidence that degeneracy alone predicts LP gain across datasets ($\\rho{=}0.052$, $n{=}23$, $p{=}0.81$; post-hoc power: 80\\% power requires $n{\\approx}85$ for $\\rho{=}0.3$; Figure~\\ref{fig:degeneracy_scatter}), though degeneracy co-varies with LP within fixed settings ($\\rho{=}{-}0.881$; Appendix~\\ref{app:per_type_lp}).\nThe cascade stages interact rather than combining into a predictive model ($R^2{<}0$); each is supported by controlled ablations (\\S\\ref{sec:fewnerd}, \\S\\ref{sec:discussion}).\n",
      "numLines": 50,
      "startLine": 1,
      "totalLines": 50
    }
  }
}
```

</details>

---

### Tool call

_source line 37_

<details open><summary>🔧 Tool call — Grep · `toolu_01U5CcU6mr2TkcRkx8S9ELjL`</summary>

```json
{
  "pattern": "0\\.4[5-9]\\d*|0\\.5[0-9]",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "9470b80f-ae39-46e4-b2fd-54cd3c772852",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GQ3V4ZZXkfYWcsz7vu1GG4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11090,
      "cache_read_input_tokens": 32538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11090
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

_source line 38 · 2026-05-21T12:01:01.883Z_

<details><summary>↩ Tool result · `toolu_01U5CcU6mr2TkcRkx8S9ELjL`</summary>

```text
&lt;persisted-output>
Output too large (21.3KB). Full output saved to: /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/ae3cc154-f589-46df-b165-661b1879021e/tool-results/toolu_01U5CcU6mr2TkcRkx8S9ELjL.txt

Preview (first 2KB):
docs/paper/sections/experiments.tex:103:The pattern matches observations: Few-NERD (low degeneracy, strong alignment) yields $+1.39$\,pp; SciERC (weak alignment) $+0.04{\pm}0.48$\,pp (3-seed; Table~\ref{tab:multiseed}); CoNLL (high degeneracy) none; WNUT-17 shows reversed LP ($\rho{=}{-}0.446$) yet QE remains effective (VC $\rho{=}0.724$, $N{=}16$; Table~\ref{tab:wnut}).
docs/paper/sections/experiments.tex:120:WNUT-17 & 1{,}287 & .452 & 67.9\% & $-$.446 & $-$0.45\,pp & .72 \\
docs/paper/sections/experiments.tex:233:SciERC & LP & $.646{\pm}.002$ & $\mathbf{.656{\pm}.003}$ & $+1.02{\pm}0.49$\,pp & .004 \\
docs/paper/sections/experiments.tex:236:Few-NERD & LP & $.748$ & $\mathbf{.762{\pm}.005}$ & $+1.40{\pm}0.51$\,pp & ${<}.001^\dagger$ \\
docs/paper/sections/experiments.tex:237:         & Unif. & $.748$ & $.756{\pm}.006$ & $+0.74{\pm}0.58$\,pp & .003 \\
docs/paper/sections/experiments.tex:244:LP-weighted construction improves on Few-NERD ($+1.40{\pm}0.51$\,pp, $p{<}0.001$; survives Holm--Bonferroni at $k{=}57$) and SciERC ($+1.02{\pm}0.49$\,pp, $p{=}0.004$, $p_{\text{adj}}{=}0.20$; Table~\ref{tab:entity_construction}), recovering 8--11\% of oracle headroom. CoNLL shows no gain ($-0.39$\,pp), consistent with high degeneracy ($N$-scaling in Appendix~\ref{app:n_scaling}).
docs/paper/sections/experiments.tex:247:Construction and LP selection are complementary, governed by $\rho_{\text{adj}}$: Few-NERD ($\rho_{\text{adj}}{=}0.516$) favors both, while SciERC ($\rho_{\text{adj}}{=}0.167$) favors construction only. A three-way routing protocol ($\rho_{\text{adj}} \geq 0.3$: LP; $<0.3$ with positive construction: construction; else: greedy) is stable across $\tau{\in}[0.2, 0.4]$.
...
&lt;/persisted-output>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "1b939415-f7d0-4d45-a49d-ba7a47f63de2",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:103:The pattern matches observations: Few-NERD (low degeneracy, strong alignment) yields $+1.39$\\,pp; SciERC (weak alignment) $+0.04{\\pm}0.48$\\,pp (3-seed; Table~\\ref{tab:multiseed}); CoNLL (high degeneracy) none; WNUT-17 shows reversed LP ($\\rho{=}{-}0.446$) yet QE remains effective (VC $\\rho{=}0.724$, $N{=}16$; Table~\\ref{tab:wnut}).\ndocs/paper/sections/experiments.tex:120:WNUT-17 & 1{,}287 & .452 & 67.9\\% & $-$.446 & $-$0.45\\,pp & .72 \\\\\ndocs/paper/sections/experiments.tex:233:SciERC & LP & $.646{\\pm}.002$ & $\\mathbf{.656{\\pm}.003}$ & $+1.02{\\pm}0.49$\\,pp & .004 \\\\\ndocs/paper/sections/experiments.tex:236:Few-NERD & LP & $.748$ & $\\mathbf{.762{\\pm}.005}$ & $+1.40{\\pm}0.51$\\,pp & ${<}.001^\\dagger$ \\\\\ndocs/paper/sections/experiments.tex:237:         & Unif. & $.748$ & $.756{\\pm}.006$ & $+0.74{\\pm}0.58$\\,pp & .003 \\\\\ndocs/paper/sections/experiments.tex:244:LP-weighted construction improves on Few-NERD ($+1.40{\\pm}0.51$\\,pp, $p{<}0.001$; survives Holm--Bonferroni at $k{=}57$) and SciERC ($+1.02{\\pm}0.49$\\,pp, $p{=}0.004$, $p_{\\text{adj}}{=}0.20$; Table~\\ref{tab:entity_construction}), recovering 8--11\\% of oracle headroom. CoNLL shows no gain ($-0.39$\\,pp), consistent with high degeneracy ($N$-scaling in Appendix~\\ref{app:n_scaling}).\ndocs/paper/sections/experiments.tex:247:Construction and LP selection are complementary, governed by $\\rho_{\\text{adj}}$: Few-NERD ($\\rho_{\\text{adj}}{=}0.516$) favors both, while SciERC ($\\rho_{\\text{adj}}{=}0.167$) favors construction only. A three-way routing protocol ($\\rho_{\\text{adj}} \\geq 0.3$: LP; $<0.3$ with positive construction: construction; else: greedy) is stable across $\\tau{\\in}[0.2, 0.4]$.\ndocs/paper/sections/conclusion.tex:3:NER exhibits oracle scaling ($c{\\approx}0.5$) but aggregation fails above $\\theta_{\\text{crit}}{=}0.70$; entity construction and LP selection ($+0.4$\\textendash$1.4$\\,pp) bypass the introspection boundary (AUROC $0.63$\\textendash$0.88$ vs.\\ ESJ $0.51$) rather than resolve it.\ndocs/paper/sections/mechanistic.tex:8:Entity-level AUROC is $0.512$---indistinguishable from chance---with P(yes$|$correct)${=}0.500$ and P(yes$|$incorrect)${=}0.500$.\ndocs/paper/sections/mechanistic.tex:12:Re-prompting on disputed entities (agreement ${<}0.6$) with focused verification yields P(yes) separation of $0.0006$ between gold and non-gold entities ($0.5003$ vs.\\ $0.4997$).\ndocs/paper/sections/mechanistic.tex:21:All three exceed ESJ ($0.51$); only CoNLL approaches frequency agreement ($0.868$).\ndocs/paper/sections/mechanistic.tex:22:Cross-dataset transfer is weak: leave-one-dataset-out AUROC drops to $0.559$ (Few-NERD${\\to}$CoNLL) and $0.671$ (CoNLL${\\to}$Few-NERD), indicating dataset-specific rather than universal encoding.\ndocs/paper/sections/mechanistic.tex:26:Entity quality is partially encoded in hidden representations: a supervised probe (AUROC $0.63$\\textendash$0.88$) consistently exceeds self-judgment (ESJ $0.51$) but only marginally exceeds multi-sample agreement ($0.87$) on CoNLL, suggesting consensus captures information beyond single-pass representations while the prompt interface fails to access even partial hidden-state signal.\ndocs/paper/sections/mechanistic.tex:27:LODO transfer drops to $0.56$\\textendash$0.67$, so even direct hidden-state access would not yield a universal quality signal---explaining the negative cross-dataset verifier transfer (\\S\\ref{sec:verifier}).\ndocs/paper/sections/limitations.tex:19:Our selection experiments use 3 training seeds for Few-NERD and CoNLL (stability $\\sigma{\\leq}0.04$~pp for LP selection); these confirm robustness on the key positive and negative datasets. SciERC uses 1 primary seed with high seed sensitivity ($\\sigma{=}0.48$~pp, $n{=}529$), which reflects limited within-seed statistical power.\ndocs/paper/sections/adaptive.tex:18:Self-verif.\\ (prompt) & ESJ & AUROC $0.51$ & \\ref{sec:mechanistic} \\\\\ndocs/paper/sections/adaptive.tex:27:{\\footnotesize $^\\dagger$Few-NERD only; SciERC $+0.2$\\,pp ($p{=}0.29$). $^\\ddagger$Seed-sensitive ($\\sigma{=}0.48$\\,pp).}\ndocs/paper/sections/adaptive.tex:33:Combining 4 samples each from Qwen3-8B and LLaMA-3.1-8B (Few-NERD) yields $+0.42$\\,pp over pure LLaMA ($p{<}0.001$, CI $[0.27, 0.58]$; $N{=}8$ total).\ndocs/paper/sections/abstract.tex:5:Quality estimation signals correlate with oracle F1 ($\\rho$ up to 0.45, AUROC up to 0.82) yet no signal selects better than greedy decoding.\ndocs/paper/sections/abstract.tex:7:A hidden-state linear probe achieves entity-level discrimination (area under the ROC curve [AUROC] $0.63$\\textendash$0.88$, dataset-dependent) from a single forward pass, consistently exceeding prompt-based self-evaluation (AUROC 0.51) but matching multi-sample agreement ($0.87$) only on the simplest task.\ndocs/paper/sections/experiments_main.tex:60:WNUT-17 & 1{,}287 & .452 & 67.9\\% & $-$.446 & $-$0.45\\,pp & .72 \\\\\ndocs/paper/sections/experiments_main.tex:107:SciERC & LP & $.646{\\pm}.002$ & $\\mathbf{.656{\\pm}.003}$ & $+1.02{\\pm}0.49$\\,pp & .004 \\\\\ndocs/paper/sections/experiments_main.tex:110:Few-NERD & LP & $.748$ & $\\mathbf{.762{\\pm}.005}$ & $+1.40{\\pm}0.51$\\,pp & ${<}.001^\\dagger$ \\\\\ndocs/paper/sections/experiments_main.tex:111:         & Unif. & $.748$ & $.756{\\pm}.006$ & $+0.74{\\pm}0.58$\\,pp & .003 \\\\\ndocs/paper/sections/experiments_main.tex:118:LP-weighted construction improves on Few-NERD ($+1.40{\\pm}0.51$\\,pp, $p{<}0.001$; Holm $p_{\\text{adj}}{=}0.006$, $k{=}10$) and SciERC ($+1.02{\\pm}0.49$\\,pp, $p{=}0.004$, $p_{\\text{adj}}{=}0.20$), recovering 8--11\\% of oracle headroom; CoNLL shows no gain ($-0.39$\\,pp), consistent with high degeneracy.\ndocs/paper/sections/experiments_main.tex:122:Construction and LP selection are complementary, governed by within-instance LP alignment $\\rho_{\\text{adj}}$ (Few-NERD $0.516$ favors both; SciERC $0.167$ favors construction only).\ndocs/paper/sections/introduction.tex:20:Five quality estimation (QE) signals achieve rank correlations up to $\\rho{=}0.45$ and AUROC up to 0.82 with oracle F1, yet no signal outperforms greedy decoding on SciERC ($p{>}0.05$ for all comparisons).\ndocs/paper/sections/introduction.tex:25:ESJ achieves AUROC of 0.51 (indistinguishable from chance), while frequency-based agreement reaches 0.87.\ndocs/paper/sections/introduction.tex:28:A supervised hidden-state probe achieves entity-level AUROC${=}0.63$\\textendash$0.88$ across three datasets from a single forward pass, exceeding prompt-based self-judgment (${=}0.51$) but not uniformly exceeding multi-sample agreement (${=}0.87$)---an introspection boundary modulated by task complexity (\\S\\ref{sec:mechanistic}).\ndocs/paper/sections/introduction.tex:39:\\caption{Overview of the correlation-selection gap (diagnostic sequence, not causal chain). \\textbf{Left}: consistency signals estimate instance quality ($\\rho$ up to 0.45; Table~\\ref{tab:quality_estimation}). \\textbf{Center}: instance-level signals assign identical scores to all $N$ candidates, so selection cannot outperform greedy. \\textbf{Right}: LP-weighted entity construction ($\\theta{=}2/N$) bypasses the bottleneck ($+1.40$\\,pp on Few-NERD; \\S\\ref{sec:prescriptive}).}\ndocs/paper/sections/introduction.tex:52:    A supervised probe achieves entity-level AUROC${=}0.63$\\textendash$0.88$ (GroupKFold CV), exceeding self-judgment (${=}0.51$) but falling below multi-sample agreement (${=}0.87$) on two of three datasets---hidden states encode partial entity quality inaccessible through prompting (\\S\\ref{sec:mechanistic}).\ndocs/paper/sections/appendix.tex:58:\\quad SJ &  & $0.474{\\pm}0.009$ & --- \\\\\ndocs/paper/sections/appendix.tex:59:\\quad FK &  & $0.467{\\pm}0.009$ & --- \\\\\ndocs/paper/sections/appendix.tex:60:\\quad EM &  & $0.473{\\pm}0.010$ & --- \\\\\ndocs/paper/sections/appendix.tex:61:\\quad VC &  & $0.470{\\pm}0.006$ & --- \\\\\ndocs/paper/sections/appendix.tex:92:[Omitted long matching line]\ndocs/paper/sections/appendix.tex:110:CoNLL (LLaMA) & 2{,}756 & 0.927 & [0.919, 0.935] & 225.9 & 0.578 \\\\\ndocs/paper/sections/appendix.tex:111:CoNLL (Qwen) & 2{,}756 & 0.720 & [0.706, 0.734] & 102.1 & 0.520 \\\\\ndocs/paper/sections/appendix.tex:119:Split-half reliability ranges from $r{=}0.395$ (SciERC) to $r{=}0.578$ (CoNLL LLaMA), moderate stability: FK estimates from half the samples correlate positively with those from the other half, though the SciERC value suggests noisier estimation on harder tasks with fewer samples.\ndocs/paper/sections/appendix.tex:150:For NER, SJ effectiveness scales with structural complexity: on SciERC instances with 6+ entities, $\\rho{=}0.547$, compared to $\\rho{=}0.415$ for 1--2 entities.\ndocs/paper/sections/appendix.tex:152:For RE, SJ $\\rho$ increases monotonically with sentence length (Q1: 0.110 $\\to$ Q4: 0.473; Fisher $z$-test $p{=}0.004$): longer, more relation-dense sentences provide richer structure for consistency-based estimation.\ndocs/paper/sections/appendix.tex:155:On the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\\rho{=}0.630$, LP $\\rho{=}0.554$, and SJ $\\rho{=}0.502$, all far above the full-set levels.\ndocs/paper/sections/appendix.tex:200:On LLaMA conditional RE (non-zero F1 instances), SJ recovers to $\\rho{=}0.405$ while FK drops to $\\rho{=}0.259$, consistent with the NER structural advantage; on full-set RE, however, the SJ--FK difference is non-significant ($\\Delta\\rho{=}{-}0.005$, $p{=}0.53$; preliminary).\ndocs/paper/sections/appendix.tex:202:EM ranks first across all four tested conditional configurations: SciERC NER ($\\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\\rho{=}0.466$), CoNLL LLaMA 3-seed ($\\rho{=}0.462$), and SciERC RE ($\\rho{=}0.417$). This holds despite full-set rankings ranging from \\#1 (CoNLL Qwen) to \\#5 (SciERC RE).\ndocs/paper/sections/appendix.tex:205:The margin over SJ is largest on RE ($\\Delta\\rho{=}{+}0.171$), where compound extraction decisions amplify output variability, and smallest on CoNLL LLaMA ($\\Delta\\rho{=}{+}0.002$), where all signals converge near $\\rho{\\approx}0.46$.\ndocs/paper/sections/appendix.tex:228:VC's high full-set $\\rho{=}0.724$ is entirely driven by the zero/non-zero boundary (conditional $\\rho{=}0.038$, $p{=}0.49$), while LP's conditional $\\rho{=}0.350$ is the highest among all signals on the non-zero subset, full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.\ndocs/paper/sections/appendix.tex:233:[Omitted long matching line]\ndocs/paper/sections/appendix.tex:286:VC & +0.379 & [+0.299, +0.456] \\\\\ndocs/paper/sections/appendix.tex:355:24 & & CoNLL uniform construction (Qwen) & $0.500$ & $1.0$ &  \\\\\ndocs/paper/sections/appendix.tex:357:26 & & SciERC FS construction (72B) & $0.544$ & $1.0$ &  \\\\\ndocs/paper/sections/appendix.tex:375:40 & & SciERC RE $\\Delta\\rho$ SJ$-$FK (full-set) & $0.530$ & $1.0$ &  \\\\\ndocs/paper/sections/appendix.tex:393:52 & & LP distribution seed 42 vs 456 (Mann--Whitney) & $0.550$ & $1.0$ &  \\\\\ndocs/paper/sections/appendix.tex:395:54 & & WNUT-17 conditional $\\rho$ VC ($p$-value) & $0.487$ & $1.0$ &  \\\\\ndocs/paper/sections/appendix.tex:397:56 & & SciERC LP favorable subset ($+$2.47 pp) & $0.015$ & $0.585$ &  \\\\\ndocs/paper/sections/appendix.tex:457:Within-inst.\\ SJ $\\rho$ (median) & 0.524 & 0.550 & 0.990 \\\\\ndocs/paper/sections/appendix.tex:518:(b)~Closed-source APIs where log-probabilities are unavailable make consistency signals the only viable selection mechanism; our structural signals (SJ, VC, FK, EM) provide quality estimation ($\\rho$ up to 0.45) even without model-internal access.\ndocs/paper/sections/appendix.tex:537:In-domain OOF construction yields $+0.30$\\,pp overall, with per-dataset gains of $+1.28$\\,pp (SciERC), $+0.55$\\,pp (CoNLL), and $+0.02$\\,pp (Few-NERD).\ndocs/paper/sections/appendix.tex:621:ESJ (best $\\theta{=}0.02$) & AUROC${=}0.512$ & .711 \\\\\ndocs/paper/sections/appendix.tex:623:LSC (centroid) & $\\rho_{\\text{LP-latent}}{=}0.52$ & .759 \\\\\ndocs/paper/sections/appendix.tex:633:The entity-level AUROC is $0.512$---indistinguishable from chance---with P(yes$|$correct)${=}0.500$ and P(yes$|$incorrect)${=}0.500$ (separation $0.001$).\ndocs/paper/sections/appendix.tex:638:P(yes) separation between gold and non-gold entities is $0.0006$ ($0.5003$ vs.\\ $0.4997$), and MRSC best F1 ($0.763$) falls below both greedy and MV.\ndocs/paper/sections/appendix.tex:646:The probe consistently exceeds prompt-based self-evaluation (ESJ AUROC${=}0.512$), confirming that hidden states encode partial entity quality signal inaccessible through the prompt interface, consistent with the complexity-dependent introspection boundary diagnosed in the main text (\\S\\ref{sec:mechanistic}).\ndocs/paper/sections/appendix.tex:759:Seed~456 uses a different subtask flag (joint vs.\\ ner for seeds 42 and 123); the LP distributions are statistically indistinguishable (median LP: 8.37 vs.\\ 8.20 nats; Mann--Whitney $p{=}0.55$); the subtask change does not affect compression.\ndocs/paper/sections/appendix.tex:805:0.01 & 1.1\\% & 523 & $+$0.58 & .21 \\\\\ndocs/paper/sections/appendix.tex:835:VC & 2.33 & 0.53 & 0.72 & 0.18 \\\\\ndocs/paper/sections/appendix.tex:868:CoNLL alignment is moderate ($\\rho{\\approx}0.51$), but the valid-instance fraction is low (38\\% for Qwen, 11\\% for LLaMA) because degeneracy eliminates most headroom before alignment can operate.\ndocs/paper/sections/appendix.tex:883:CoNLL & Qwen3-8B & 0.506 & 1{,}124 / 2{,}756 & 41\\% \\\\\ndocs/paper/sections/appendix.tex:884:CoNLL & LLaMA-3.1-8B & 0.512 & 298 / 2{,}756 & 11\\% \\\\\ndocs/paper/sections/appendix.tex:903:Q1 (low) & 0.30 & $+$1.55 & $+$0.54 & 16.85 \\\\\ndocs/paper/sections/appendix.tex:904:Q2 & 0.51 & $-$0.65 & $-$1.89 & 14.35 \\\\\ndocs/paper/sections/appendix.tex:964:Oracle & 0.585 & 0.757 \\\\\ndocs/paper/sections/appendix.tex:968:EM & 0.372 & 0.583 \\\\\ndocs/paper/sections/appendix.tex:969:VC & 0.359 & 0.574 \\\\\ndocs/paper/sections/appendix.tex:1046:The non-tied subset ($n{=}210$) is partially reshuffled under free-form decoding: Jaccard similarity between the constrained and free-form non-tied sets is 0.472: 87 instances newly gain LP discrimination while others lose it, and the newly non-tied subset shows a $3{\\times}$ increase in within-instance LP range for the newly non-tied subset.\ndocs/paper/sections/appendix.tex:1133:CoNLL ($\\delta{=}60.3\\% > 1{-}0.456{=}54.4\\%$) exceeds the impossibility threshold; Few-NERD and SciERC remain below it but still show negligible gains due to low alignment $\\alpha$.\ndocs/paper/sections/appendix.tex:1134:SciERC's lower $\\alpha_{\\textup{crit}}$ ($0.333$, vs.\\ $0.396$ for Few-NERD and $0.456$ for CoNLL) is consistent with it being the only dataset where a trained entity verifier (AUC${=}0.923$) achieves positive gain ($+1.28$\\,pp).\ndocs/paper/sections/appendix.tex:1146:CoNLL & 2 & .912 & .914 & .952 & $+0.16{\\pm}0.17$ & 60.3\\% & 0.456 & \\textbf{Yes} \\\\\ndocs/paper/sections/appendix.tex:1240:Quality estimation under free-form decoding yields SJ $\\rho{=}0.461$, EM $\\rho{=}0.471$, LP $\\rho{=}0.326$, comparable to constrained results (Table~\\ref{tab:quality_estimation}).\ndocs/paper/sections/appendix.tex:1248:LP selection failures (instances where LP-selected F1 $<$ single-sample F1) show moderate cross-seed stability: the average pairwise Jaccard similarity is 0.42 (range: 0.38--0.46); failures are partially systematic (driven by instance complexity) but not fully deterministic.\ndocs/paper/sections/appendix.tex:1266:Stable fail (3 seeds) & 34 & 2.12 & 0.688 & $-$0.499 \\\\\ndocs/paper/sections/appendix.tex:1267:Fail 2+ seeds & 26 & 2.46 & 0.774 & $-$0.450 \\\\\ndocs/paper/sections/appendix.tex:1277:These instances show large constrained LP errors ($\\Delta{=}{-}0.430$) that reverse under free-form decoding ($\\Delta{=}{+}0.503$), but their rarity (5/397) confirms that the RE selection flip is driven by aggregate variance reallocation rather than systematic instance-level correction.\ndocs/paper/sections/appendix.tex:1483:Qwen2.5-7B-Instruct without task-specific fine-tuning confirms the gap is model-intrinsic on CoNLL: greedy F1${=}0.538$, oracle${=}0.627$ ($+8.9$\\,pp headroom), with structural signals outperforming surface ($\\rho_{\\textup{SJ}}{=}0.467$, $\\rho_{\\textup{FK}}{=}0.435$; advantage $+0.015$) and LP AUROC${=}0.580$ (verdict: marginal).\ndocs/paper/sections/appendix.tex:1541:0.5 & $+$9.1 & 0.297 & 0.218 & 0.577 & 0.636 \\\\\ndocs/paper/sections/appendix.tex:1542:0.8 & $+$12.5 & 0.359 & 0.253 & 0.451 & 0.622 \\\\\ndocs/paper/sections/appendix.tex:1544:1.2 & $+$14.6 & 0.377 & 0.196 & 0.356 & 0.594 \\\\\ndocs/paper/sections/appendix.tex:1554:Inter-sample agreement ($\\kappa$) decreases monotonically ($0.577$ to $0.356$); higher temperature generates more diverse outputs. Mean sample F1 also decreases ($0.636$ to $0.594$), consistent with the quality--diversity trade-off.\ndocs/paper/sections/appendix.tex:1574:0.5 & 41.4 & 0.015 & 0.572 & 0.830 \\\\\ndocs/paper/sections/appendix.tex:1575:0.8 & 23.8 & 0.031 & 0.471 & 0.752 \\\\\ndocs/paper/sections/appendix.tex:1610:When the SciERC-trained model (6 NER types) is applied to CoNLL (4 types), all signals remain significant ($p{<}0.001$) and structural signals improve over their in-domain levels (same model, seed${=}42$, $N{=}8$; in-domain $\\rho$ from Table~\\ref{tab:quality_estimation}): VC reaches $\\rho{=}0.469$ (in-domain $0.379$, $\\Delta{=}{+}0.090$), SJ $\\rho{=}0.378$ (in-domain $0.360$, $\\Delta{=}{+}0.018$), and FK $\\rho{=}0.285$ (in-domain $0.267$, $\\Delta{=}{+}0.018$).\ndocs/paper/sections/appendix.tex:1611:The wider training schema subsumes CoNLL's narrower schema, so the model produces reasonable outputs even out-of-domain (single-sample F1${=}0.522$), and structural signals benefit from the simpler target schema's reduced output ambiguity.\ndocs/paper/sections/appendix.tex:1641:AUROC & 0.681 & 0.578 & 0.747 & 0.753 \\\\\ndocs/paper/sections/appendix.tex:1657:VerbConf achieves higher $\\rho$ than LP on both datasets (SciERC: 0.297 vs.\\ 0.205; CoNLL: 0.337 vs.\\ 0.316) and competitive AUROC (SciERC: 0.681 vs.\\ 0.578; CoNLL: 0.747 vs.\\ 0.753), yet yields the worst selection among all signals ($\\Delta{=}{-}2.45$~pp on SciERC, $-1.93$~pp on CoNLL).\ndocs/paper/sections/appendix.tex:1720:(2)~LP is the only signal achieving significant positive selection ($+1.39$~pp, $p{<}0.001$, CI excludes zero). The sample-level AUROC of 0.578 confirms LP provides per-sample discriminability beyond instance-level quality prediction.\ndocs/paper/sections/appendix.tex:1747:Location & 8{,}023 & 11.4 & .793 & .798 & $+$0.53 & .520 & 10.3\\,pp \\\\\ndocs/paper/sections/appendix.tex:1767:ORG & 54.3 & $-$0.55 \\\\\ndocs/paper/sections/appendix.tex:1786:OtherScientificTerm & 6.2 & $-$0.57 \\\\\ndocs/paper/sections/appendix.tex:1791:The cross-dataset degeneracy gradient (61.7\\% $\\to$ 17.8\\% $\\to$ 13.0\\%) is inversely associated with LP selection effectiveness at the macro level ($n{=}3$ datasets; exploratory).\\footnote{Partial Spearman correlation controlling for entity-type frequency yields $\\rho{=}{-}0.47$ (vs.\\ raw $\\rho{=}{-}0.38$); type frequency does not confound the degeneracy--LP relationship.}\ndocs/paper/sections/appendix.tex:1832:Within-instance LP-quality alignment is relatively stable under this convergence shift (mean $\\rho$: $0.524 \\to 0.407$; median $\\rho$: $0.667 \\to 0.615$), consistent with alignment being determined primarily by task structure rather than training duration.\ndocs/paper/sections/appendix.tex:1852:Within-inst.\\ $\\rho$ (mean) & 0.524 & 0.407 \\\\\ndocs/paper/sections/appendix.tex:1900:On SciERC, DALS yields $+0.71{\\pm}0.48$~pp (3-seed mean; individual seeds: $+0.19$ to $+1.14$~pp); on Few-NERD, $+0.30$~pp ($p{<}0.001$; gain remains positive across $\\tau \\in [0.01, 0.15]$); on CoNLL, where pure LP selection degrades F1 ($-0.85$~pp), DALS shows comparable degradation (Qwen: $-0.87$~pp; LLaMA: neutral).\ndocs/paper/sections/appendix.tex:1906:LOO regret (the gap between oracle and LOO-selected $\\tau$) ranges from 0.51 to 1.21~pp.\ndocs/paper/sections/appendix.tex:2036: & 0.50 & .649 & .654 & $+$0.46 & $+$0.97 \\\\\ndocs/paper/sections/appendix.tex:2046: & 0.50 & .725 & .728 & $-$2.25 & $-$2.01 \\\\\ndocs/paper/sections/appendix.tex:2056: & 0.50 & .897 & .899 & $-$1.12 & $-$0.94 \\\\\ndocs/paper/sections/appendix.tex:2065:Pairwise error overlap (Jaccard similarity of per-sample false-positive and false-negative entity sets) shows no significant difference between FS and ZS regimes (SciERC: $0.454$ vs.\\ $0.452$, $p{=}0.84$; CoNLL: $0.103$ vs.\\ $0.104$, $p{=}0.64$; permutation tests, 10{,}000 resamples).\ndocs/paper/sections/appendix.tex:2067:On SciERC, FS and ZS entropies are indistinguishable ($0.483$ vs.\\ $0.485$, $p{=}0.81$).\ndocs/paper/sections/appendix.tex:2211:$+0.42$\\,pp is the only unconditionally positive result among 9 method categories tested (Table~\\ref{tab:method_summary}). Its significance ($p{<}0.001$, CI $[0.27, 0.58]$; \\S\\ref{sec:cross_model}) and theoretical motivation (architecturally distinct models produce independent error distributions, breaking within-model degeneracy) distinguish it from the null results of other categories.\ndocs/paper/sections/appendix.tex:2214:We report full sweeps: construction threshold $\\theta \\in [0.05, 0.50]$ (Appendix~\\ref{app:theta_sweep}), DALS threshold $\\tau$ with LOO cross-validation (regret 0.51--1.21\\,pp; Appendix~\\ref{app:dals}), LP compression threshold $\\varepsilon \\in [0, 0.2]$ (Appendix~\\ref{app:epsilon_robustness}), and temperature $T \\in \\{0.5, 0.7, 1.0, 1.2\\}$ (Appendix~\\ref{app:t_ablation}).\ndocs/paper/sections/appendix.tex:2220:The variation is complexity-dependent and interpretable: CoNLL (4 types, 91\\% F1) at 0.882, Few-NERD (8 types, 75\\% F1) at 0.636, SciERC (6 types, 65\\% F1) at 0.630. LODO transfer drops to 0.56--0.67 (\\S\\ref{sec:mechanistic}), confirming dataset-specific encoding. The pattern---not the point estimate---is the finding.",
    "numLines": 110
  }
}
```

</details>

---

### Tool call

_source line 39_

<details open><summary>🔧 Tool call — Grep · `toolu_01MXQWdmUWE9X3p2kr1ab5AP`</summary>

```json
{
  "pattern": "rho.*0\\.[3-5]|\\\\rho.*0\\.[3-5]|ρ.*0\\.[3-5]",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "404aaf4a-b8b8-4625-8fc8-ca6ecd68a6a5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GQ3V4ZZXkfYWcsz7vu1GG4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11090,
      "cache_read_input_tokens": 32538,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11090
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

_source line 40 · 2026-05-21T12:01:03.081Z_

<details><summary>↩ Tool result · `toolu_01MXQWdmUWE9X3p2kr1ab5AP`</summary>

```text
&lt;persisted-output>
Output too large (20.7KB). Full output saved to: /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/ae3cc154-f589-46df-b165-661b1879021e/tool-results/toolu_01MXQWdmUWE9X3p2kr1ab5AP.txt

Preview (first 2KB):
docs/paper/sections/experiments.tex:46:On SciERC (medium difficulty), structural signals lead (VC $\rho{=}0.379$, SJ $0.360$) over LP ($0.205$); bootstrap CIs confirm the gap ($\Delta\rho{=}{+}0.155$; Appendix~\ref{app:bootstrap_signal}).
docs/paper/sections/experiments.tex:48:At the signal-collapse boundary (WNUT-17, macro F1${\approx}$42\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\rho{=}0.724$ at $N{=}16$, but conditional $\rho{=}0.038$; Table~\ref{tab:wnut}); LP shows the reverse (conditional $\rho{=}0.350$; Figure~\ref{fig:signal_heatmap}).
docs/paper/sections/experiments.tex:89:\caption{The correlation-selection gap on SciERC ($N{=}8$, $T{=}1.0$). Bars: quality estimation $\rho$ (seed 42); line with error bars: $\Delta$F1 vs.\ greedy (3-seed mean, seeds 42/123/456). Despite $\rho$ up to 0.38, no signal significantly outperforms greedy (all $p{>}0.05$; Table~\ref{tab:selection}). Dashed green: oracle upper bound ($+13.0$~pp); dotted gray: random baseline.}
docs/paper/sections/experiments.tex:102:Three factors shape LP selection gains: (1)~\textit{instance degeneracy} (SciERC 17.8\%, CoNLL 61.7\%; Table~\ref{tab:fewnerd}); (2)~\textit{oracle headroom} (CoNLL ${\approx}4$\,pp vs.\ SciERC 13.0\,pp); (3)~\textit{LP-quality alignment} (Few-NERD $\rho{\approx}0.5$--$0.7$ vs.\ SciERC $\rho{\approx}0.26$).
docs/paper/sections/experiments.tex:103:The pattern matches observations: Few-NERD (low degeneracy, strong alignment) yields $+1.39$\,pp; SciERC (weak alignment) $+0.04{\pm}0.48$\,pp (3-seed; Table~\ref{tab:multiseed}); CoNLL (high degeneracy) none; WNUT-17 shows reversed LP ($\rho{=}{-}0.446$) yet QE remains effective (VC $\rho{=}0.724$, $N{=}16$; Table~\ref{tab:wnut}).
...
&lt;/persisted-output>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "9881de8d-b374-46e4-993b-0142bf3d9e71",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:46:On SciERC (medium difficulty), structural signals lead (VC $\\rho{=}0.379$, SJ $0.360$) over LP ($0.205$); bootstrap CIs confirm the gap ($\\Delta\\rho{=}{+}0.155$; Appendix~\\ref{app:bootstrap_signal}).\ndocs/paper/sections/experiments.tex:48:At the signal-collapse boundary (WNUT-17, macro F1${\\approx}$42\\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\\rho{=}0.724$ at $N{=}16$, but conditional $\\rho{=}0.038$; Table~\\ref{tab:wnut}); LP shows the reverse (conditional $\\rho{=}0.350$; Figure~\\ref{fig:signal_heatmap}).\ndocs/paper/sections/experiments.tex:89:\\caption{The correlation-selection gap on SciERC ($N{=}8$, $T{=}1.0$). Bars: quality estimation $\\rho$ (seed 42); line with error bars: $\\Delta$F1 vs.\\ greedy (3-seed mean, seeds 42/123/456). Despite $\\rho$ up to 0.38, no signal significantly outperforms greedy (all $p{>}0.05$; Table~\\ref{tab:selection}). Dashed green: oracle upper bound ($+13.0$~pp); dotted gray: random baseline.}\ndocs/paper/sections/experiments.tex:102:Three factors shape LP selection gains: (1)~\\textit{instance degeneracy} (SciERC 17.8\\%, CoNLL 61.7\\%; Table~\\ref{tab:fewnerd}); (2)~\\textit{oracle headroom} (CoNLL ${\\approx}4$\\,pp vs.\\ SciERC 13.0\\,pp); (3)~\\textit{LP-quality alignment} (Few-NERD $\\rho{\\approx}0.5$--$0.7$ vs.\\ SciERC $\\rho{\\approx}0.26$).\ndocs/paper/sections/experiments.tex:103:The pattern matches observations: Few-NERD (low degeneracy, strong alignment) yields $+1.39$\\,pp; SciERC (weak alignment) $+0.04{\\pm}0.48$\\,pp (3-seed; Table~\\ref{tab:multiseed}); CoNLL (high degeneracy) none; WNUT-17 shows reversed LP ($\\rho{=}{-}0.446$) yet QE remains effective (VC $\\rho{=}0.724$, $N{=}16$; Table~\\ref{tab:wnut}).\ndocs/paper/sections/experiments.tex:202:LP $\\rho$ drops without fine-tuning (Table~\\ref{tab:scale_comparison}) and LP selection fails on all datasets. Structural signals generalize (Few-NERD VC $\\rho{=}0.416$). Degeneracy increases (Few-NERD: $46.2$\\% vs.\\ $13.0$\\%; CoNLL: $67.7$\\% vs.\\ $61.7$\\%); this comparison simultaneously varies model family, regime, and quantization, so individual effects cannot be disentangled.\ndocs/paper/sections/experiments.tex:247:Construction and LP selection are complementary, governed by $\\rho_{\\text{adj}}$: Few-NERD ($\\rho_{\\text{adj}}{=}0.516$) favors both, while SciERC ($\\rho_{\\text{adj}}{=}0.167$) favors construction only. A three-way routing protocol ($\\rho_{\\text{adj}} \\geq 0.3$: LP; $<0.3$ with positive construction: construction; else: greedy) is stable across $\\tau{\\in}[0.2, 0.4]$.\ndocs/paper/sections/theory.tex:14:The gap persists across scales and families: scaling from 8B to 14B FT increases oracle headroom ($+1.2$\\,pp) with minimal greedy gain ($+0.9$\\,pp), and GPT-5.5 (200 Few-NERD instances, zero-shot) exhibits the same pattern---50\\% degeneracy, SJ $\\rho{=}0.346$, MV $+1.4$\\,pp yet 6.8\\,pp oracle headroom unrealized.\\footnote{10.1\\% of GPT-5.5 samples produced unparseable output; these are excluded from all metrics. See Appendix~\\ref{app:frontier_sc}.}\ndocs/paper/sections/single_signal.tex:35:\\caption{Correlation-selection gap on SciERC ($N{=}8$, $T{=}1.0$). Bars: QE $\\rho$; line: $\\Delta$F1 vs.\\ greedy (3-seed mean). Despite $\\rho$ up to 0.38, no signal outperforms greedy ($p{>}0.05$). Dashed green: oracle ($+13.0$\\,pp); dotted gray: random.}\ndocs/paper/sections/single_signal.tex:39:Despite $\\rho$ up to 0.38, no signal outperforms greedy on SciERC (Table~\\ref{tab:selection}; Figure~\\ref{fig:selection_gap}); the oracle reveals 13.0\\,pp headroom, but LP achieves $+0.2$\\,pp ($p{=}0.29$), below MDE (${\\approx}$1.5\\,pp; $n{=}529$).\ndocs/paper/sections/single_signal.tex:47:(3)~LP compression limits exploitation of that opportunity (Few-NERD within-instance $\\rho{\\approx}0.5$--$0.7$ vs.\\ SciERC $\\rho{\\approx}0.26$).\ndocs/paper/sections/single_signal.tex:48:We did not find evidence that degeneracy alone predicts LP gain across datasets ($\\rho{=}0.052$, $n{=}23$, $p{=}0.81$; post-hoc power: 80\\% power requires $n{\\approx}85$ for $\\rho{=}0.3$; Figure~\\ref{fig:degeneracy_scatter}), though degeneracy co-varies with LP within fixed settings ($\\rho{=}{-}0.881$; Appendix~\\ref{app:per_type_lp}).\ndocs/paper/sections/abstract.tex:5:Quality estimation signals correlate with oracle F1 ($\\rho$ up to 0.45, AUROC up to 0.82) yet no signal selects better than greedy decoding.\ndocs/paper/sections/appendix.tex:37:\\caption{Signal robustness across configurations (Spearman $\\rho$). Top: temperature on Qwen SciERC. Middle: sample size on Qwen SciERC. Bottom: transfer across model families (both 8B) (LLaMA CoNLL $N{=}16$, 3-seed mean $\\pm\\sigma$). $^\\dagger$Mean over 3 seeds ($\\sigma{=}0.013$; individual: 0.398, 0.423, 0.410). $\\sigma$ computed as sample standard deviation.}\ndocs/paper/sections/appendix.tex:75:SJ NER $\\rho$ shifts from 0.364 ($T{=}0.7$) to 0.360 ($T{=}1.0$), a difference of 0.004.\ndocs/paper/sections/appendix.tex:81:Increasing from $N{=}8$ to $N{=}16$ improves SJ on Qwen SciERC NER: $\\rho$ rises from 0.360 to $0.411{\\pm}0.010$ (three seeds: 0.398, 0.423, 0.410), a gain of $+0.047$.\ndocs/paper/sections/appendix.tex:90:LLaMA-3.1-8B-Instruct shows a similar SJ--FK ordering on SciERC NER (SJ $\\rho{=}0.325{\\pm}0.021$, FK $\\rho{=}0.256{\\pm}0.024$, $\\Delta\\rho{=}0.069$; permutation $p{=}0.06$, borderline).\ndocs/paper/sections/appendix.tex:91:On CoNLL, the gap across model families is minimal (Table~\\ref{tab:quality_estimation}): SJ achieves $\\rho{=}0.431$ (LLaMA) vs.\\ 0.436 (Qwen), $\\Delta{=}0.005$.\ndocs/paper/sections/appendix.tex:92:[Omitted long matching line]\ndocs/paper/sections/appendix.tex:139:\\caption{Quality estimation heatmap (Spearman $\\rho$) across five signals and four configurations. Left: full evaluation set; right: conditional set (non-zero F1 instances). On the full set, structural signals dominate on SciERC NER while all signals converge on CoNLL. On the conditional set, EM emerges as the strongest signal on both NER ($\\rho{=}0.360$) and RE ($\\rho{=}0.417$), while LP RE collapses to near-zero ($\\rho{=}0.011$).}\ndocs/paper/sections/appendix.tex:150:For NER, SJ effectiveness scales with structural complexity: on SciERC instances with 6+ entities, $\\rho{=}0.547$, compared to $\\rho{=}0.415$ for 1--2 entities.\ndocs/paper/sections/appendix.tex:152:For RE, SJ $\\rho$ increases monotonically with sentence length (Q1: 0.110 $\\to$ Q4: 0.473; Fisher $z$-test $p{=}0.004$): longer, more relation-dense sentences provide richer structure for consistency-based estimation.\ndocs/paper/sections/appendix.tex:155:On the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\\rho{=}0.630$, LP $\\rho{=}0.554$, and SJ $\\rho{=}0.502$, all far above the full-set levels.\ndocs/paper/sections/appendix.tex:159:Figure~\\ref{fig:length_logprob_scatter} shows that mean log-probability is weakly positively correlated with output length (NER: $\\rho{=}0.386$, $n{=}4{,}232$; RE: $\\rho{=}0.326$, $n{=}3{,}176$), ruling out length-penalty confounding as an explanation for LP's selection failure: longer outputs receive \\textit{higher}, not lower, token-averaged log-probability under constrained decoding.\ndocs/paper/sections/appendix.tex:164:\\caption{Output length vs.\\ mean log-probability on SciERC ($N{=}8$, $T{=}1.0$). Positive correlations (NER: $\\rho{=}0.386$; RE: $\\rho{=}0.326$) rule out length-penalty confounding.}\ndocs/paper/sections/appendix.tex:200:On LLaMA conditional RE (non-zero F1 instances), SJ recovers to $\\rho{=}0.405$ while FK drops to $\\rho{=}0.259$, consistent with the NER structural advantage; on full-set RE, however, the SJ--FK difference is non-significant ($\\Delta\\rho{=}{-}0.005$, $p{=}0.53$; preliminary).\ndocs/paper/sections/appendix.tex:201:At $N{=}16$, the divergence persists: SJ maintains $\\rho{=}0.308$ on conditional RE while LP drops to $\\rho{=}{-}0.026$.\ndocs/paper/sections/appendix.tex:202:EM ranks first across all four tested conditional configurations: SciERC NER ($\\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\\rho{=}0.466$), CoNLL LLaMA 3-seed ($\\rho{=}0.462$), and SciERC RE ($\\rho{=}0.417$). This holds despite full-set rankings ranging from \\#1 (CoNLL Qwen) to \\#5 (SciERC RE).\ndocs/paper/sections/appendix.tex:205:The margin over SJ is largest on RE ($\\Delta\\rho{=}{+}0.171$), where compound extraction decisions amplify output variability, and smallest on CoNLL LLaMA ($\\Delta\\rho{=}{+}0.002$), where all signals converge near $\\rho{\\approx}0.46$.\ndocs/paper/sections/appendix.tex:228:VC's high full-set $\\rho{=}0.724$ is entirely driven by the zero/non-zero boundary (conditional $\\rho{=}0.038$, $p{=}0.49$), while LP's conditional $\\rho{=}0.350$ is the highest among all signals on the non-zero subset, full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.\ndocs/paper/sections/appendix.tex:260:This asymmetry gives structural signals a relative advantage in the compute-constrained regime: at $N{=}8$, SJ already achieves $\\rho{=}0.431$ on LLaMA CoNLL (vs.\\ LP $\\rho{=}0.307$, $\\Delta{=}{+}0.124$), and the gap \\textit{widens} at $N{=}16$ ($\\Delta{=}{+}0.163$) because structural signals continue to benefit from additional pairwise evidence while LP does not.\ndocs/paper/sections/appendix.tex:369:34 & & SciERC $\\Delta\\rho$ VC$-$SJ ($N{=}8$, seed 42) & $0.300$ & $1.0$ &  \\\\\ndocs/paper/sections/appendix.tex:375:40 & & SciERC RE $\\Delta\\rho$ SJ$-$FK (full-set) & $0.530$ & $1.0$ &  \\\\\ndocs/paper/sections/appendix.tex:395:54 & & WNUT-17 conditional $\\rho$ VC ($p$-value) & $0.487$ & $1.0$ &  \\\\\ndocs/paper/sections/appendix.tex:457:Within-inst.\\ SJ $\\rho$ (median) & 0.524 & 0.550 & 0.990 \\\\\ndocs/paper/sections/appendix.tex:518:(b)~Closed-source APIs where log-probabilities are unavailable make consistency signals the only viable selection mechanism; our structural signals (SJ, VC, FK, EM) provide quality estimation ($\\rho$ up to 0.45) even without model-internal access.\ndocs/paper/sections/appendix.tex:529:DeBERTa achieves $\\rho{=}0.329{\\pm}0.087$ (5-fold CV, 3 seeds). Despite moderate quality prediction, selection utility is poor: on SciERC, DeBERTa closes $-26.5{\\pm}26.5$\\% of the oracle gap (13 of 15 runs negative; vs.\\ LP's $+4.2{\\pm}10.7$\\%); on Few-NERD, DeBERTa recovers only $+3.5$\\% (single 80/20 split; vs.\\ LP's $+16.3$\\%).\ndocs/paper/sections/appendix.tex:571:On SciERC, the MLP probe achieves higher quality correlation than LP ($\\rho{=}0.388$ vs.\\ $0.283$, $+37$\\%); hidden states encode information beyond what LP captures.\ndocs/paper/sections/appendix.tex:623:LSC (centroid) & $\\rho_{\\text{LP-latent}}{=}0.52$ & .759 \\\\\ndocs/paper/sections/appendix.tex:652:On RE (Qwen only, preliminary), VC remains the top signal ($\\rho{=}0.309{\\pm}0.024$), but LP rises to \\#2 ($\\rho{=}0.297{\\pm}0.022$), above FK, SJ, and EM. This reversal from the NER ranking reflects RE's higher sensitivity to per-sample scoring.\ndocs/paper/sections/appendix.tex:787:Among instances with LP range ${\\geq}0.05$ ($n{=}210$, 40\\% of total), log-probability selection \\textit{significantly} outperforms single-sample ($+2.9$~pp F1, $p{=}0.004$), and within-instance $\\rho(\\text{LP}, \\text{F1})$ rises from 0.08 (tied subset) to 0.39 (non-tied subset).\ndocs/paper/sections/appendix.tex:788:As a continuous complement to the binary tied/non-tied analysis, pooled within-instance $\\rho(\\text{LP}, \\text{F1}){=}0.248$ across all instances confirms weak but positive per-sample signal; however, only 21.6\\% of instances achieve $p{<}0.05$ significance, and $\\rho(\\text{LP range}, \\text{F1 range}){=}0.328$ shows that instances with more LP spread also exhibit more F1 variability. LP carries information, but compression limits its exploitation.\ndocs/paper/sections/appendix.tex:868:CoNLL alignment is moderate ($\\rho{\\approx}0.51$), but the valid-instance fraction is low (38\\% for Qwen, 11\\% for LLaMA) because degeneracy eliminates most headroom before alignment can operate.\ndocs/paper/sections/appendix.tex:933:The signal ranking differs from NER: VC leads ($\\rho{=}0.309{\\pm}0.024$), but LP rises to \\#2 ($\\rho{=}0.297{\\pm}0.022$), above FK, SJ, and EM, a reversal reflecting RE's higher sensitivity to per-sample scoring.\ndocs/paper/sections/appendix.tex:941:At 4B scale (Qwen3-4B, $N{=}8$, $\\text{seed}{=}42$), RE quality estimation shows FK $\\rho{=}0.359$ and LP $\\rho{=}0.351$, both above their 8B counterparts (FK 0.275, LP 0.266), while SJ declines ($0.267$ vs.\\ $0.250$).\ndocs/paper/sections/appendix.tex:1048:Free-form decoding also slightly improves quality estimation (NER VC $\\rho$: 0.379$\\to$0.409), though this does not translate to selection gains.\ndocs/paper/sections/appendix.tex:1240:Quality estimation under free-form decoding yields SJ $\\rho{=}0.461$, EM $\\rho{=}0.471$, LP $\\rho{=}0.326$, comparable to constrained results (Table~\\ref{tab:quality_estimation}).\ndocs/paper/sections/appendix.tex:1448:LP $\\rho$ drops without fine-tuning (Table~\\ref{tab:scale_comparison}) and LP selection fails on all 72B zero-shot datasets. Structural signals generalize better (Few-NERD VC $\\rho{=}0.416$). Degeneracy increases at 72B (Few-NERD: $46.2$\\% vs.\\ $13.0$\\%; CoNLL: $67.7$\\% vs.\\ $61.7$\\%); the gap persists under this specific 72B zero-shot configuration, though scale, training regime, and quantization effects are confounded (see Limitations).\ndocs/paper/sections/appendix.tex:1483:Qwen2.5-7B-Instruct without task-specific fine-tuning confirms the gap is model-intrinsic on CoNLL: greedy F1${=}0.538$, oracle${=}0.627$ ($+8.9$\\,pp headroom), with structural signals outperforming surface ($\\rho_{\\textup{SJ}}{=}0.467$, $\\rho_{\\textup{FK}}{=}0.435$; advantage $+0.015$) and LP AUROC${=}0.580$ (verdict: marginal).\ndocs/paper/sections/appendix.tex:1512:Gemini 2.5 Pro achieves the highest oracle F1 (.758) and the highest QE correlation ($\\rho_{\\textup{SJ}}{=}0.350$, $\\rho_{\\textup{agr}}{=}0.389$) among frontier models, with balanced degeneracy (28.5\\%) preserving a 0.113 selection gap---the largest gap among models with ${\\geq}85$\\% parse success.\ndocs/paper/sections/appendix.tex:1534:\\caption{Temperature ablation on SciERC NER (Qwen3-8B, $N{=}8$, seed${=}42$). Oracle gap and QE $\\rho$ across four temperatures. $\\kappa$: Fleiss' $\\kappa$ (inter-sample agreement). $T{=}0.5$ and $T{=}1.0$ use joint (NER+RE) subtask; $T{=}0.8$ and $T{=}1.2$ use NER-only.}\ndocs/paper/sections/appendix.tex:1551:Structural QE signals improve with temperature: SJ $\\rho$ rises from $0.297$ ($T{=}0.5$) to $0.377$ ($T{=}1.2$), consistent with more diverse outputs providing richer pairwise evidence.\ndocs/paper/sections/appendix.tex:1561:However, even at $T{=}1.2$ where degeneracy (14.9\\%) approaches Few-NERD levels (${\\sim}$13\\%), within-instance $\\rho(\\text{LP}, \\text{F1})$ remains at 0.225, far below Few-NERD's ${\\sim}$0.5.\ndocs/paper/sections/appendix.tex:1610:When the SciERC-trained model (6 NER types) is applied to CoNLL (4 types), all signals remain significant ($p{<}0.001$) and structural signals improve over their in-domain levels (same model, seed${=}42$, $N{=}8$; in-domain $\\rho$ from Table~\\ref{tab:quality_estimation}): VC reaches $\\rho{=}0.469$ (in-domain $0.379$, $\\Delta{=}{+}0.090$), SJ $\\rho{=}0.378$ (in-domain $0.360$, $\\Delta{=}{+}0.018$), and FK $\\rho{=}0.285$ (in-domain $0.267$, $\\Delta{=}{+}0.018$).\ndocs/paper/sections/appendix.tex:1640:$\\rho$ & 0.297 & 0.205 & 0.337 & 0.316 \\\\\ndocs/paper/sections/appendix.tex:1657:VerbConf achieves higher $\\rho$ than LP on both datasets (SciERC: 0.297 vs.\\ 0.205; CoNLL: 0.337 vs.\\ 0.316) and competitive AUROC (SciERC: 0.681 vs.\\ 0.578; CoNLL: 0.747 vs.\\ 0.753), yet yields the worst selection among all signals ($\\Delta{=}{-}2.45$~pp on SciERC, $-1.93$~pp on CoNLL).\ndocs/paper/sections/appendix.tex:1659:The AUROC--$\\rho$ decoupling on CoNLL (LP leads AUROC at 0.753 while VerbConf leads $\\rho$ at 0.337) reflects differing sensitivity to binary vs.\\ ordinal discrimination.\ndocs/paper/sections/appendix.tex:1719:(1)~All five signals achieve positive QE ($\\rho$ 0.22--0.39); quality estimation works on Few-NERD. VC leads ($\\rho{=}0.39$), followed by FK ($0.31$), SJ ($0.30$), EM ($0.29$), LP ($0.22$); the ranking matches SciERC where structural signals also outperform LP for quality estimation.\ndocs/paper/sections/appendix.tex:1722:(4)~Low degeneracy (13.0\\%) combined with strong LP-quality alignment ($\\rho{\\approx}0.5$--$0.7$) enables LP selection: candidates differ in F1 more often, and LP can rank them effectively. This contrasts with SciERC (17.8\\% degeneracy but weak alignment $\\rho{\\approx}0.24$, LP $+0.61$~pp) and CoNLL (61.7\\%, LP $-0.85$~pp).\ndocs/paper/sections/appendix.tex:1791:The cross-dataset degeneracy gradient (61.7\\% $\\to$ 17.8\\% $\\to$ 13.0\\%) is inversely associated with LP selection effectiveness at the macro level ($n{=}3$ datasets; exploratory).\\footnote{Partial Spearman correlation controlling for entity-type frequency yields $\\rho{=}{-}0.47$ (vs.\\ raw $\\rho{=}{-}0.38$); type frequency does not confound the degeneracy--LP relationship.}\ndocs/paper/sections/appendix.tex:1832:Within-instance LP-quality alignment is relatively stable under this convergence shift (mean $\\rho$: $0.524 \\to 0.407$; median $\\rho$: $0.667 \\to 0.615$), consistent with alignment being determined primarily by task structure rather than training duration.\ndocs/paper/sections/appendix.tex:1852:Within-inst.\\ $\\rho$ (mean) & 0.524 & 0.407 \\\\\ndocs/paper/sections/appendix.tex:1861:Degeneracy increases monotonically (6.4\\% $\\to$ 17.8\\% $\\to$ 47.8\\%), and within-instance LP-quality correlation degrades in tandem (median $\\rho$: 0.319 $\\to$ 0.262 $\\to$ 0.112; mean $\\rho$: 0.273 $\\to$ 0.179 $\\to$ 0.066), confirming that overtraining erodes both diversity and LP alignment simultaneously.\ndocs/paper/sections/appendix.tex:1864:The 3-epoch model has higher within-instance alignment ($\\rho{=}0.319$) than the 5-epoch model ($\\rho{=}0.262$), yet LP selection is worse ($-1.24$ vs.\\ $+0.64$~pp): at 6.4\\% degeneracy, more non-degenerate instances enter the candidate pool, but LP ranking precision is too low to exploit them, so the broader pool hurts rather than helps. This illustrates that low degeneracy does not ensure selection gains; LP-quality alignment determines selection direction.\ndocs/paper/sections/appendix.tex:1866:[Omitted long matching line]\ndocs/paper/sections/appendix.tex:1867:Even at the most favorable epoch (3-epoch, $\\rho{=}0.319$), SciERC alignment remains below the ${\\sim}$0.5 threshold associated with successful LP selection on Few-NERD.\ndocs/paper/sections/appendix.tex:1882:Within-inst.\\ $\\rho$ (median) & 0.319 & 0.262 & 0.112 \\\\\ndocs/paper/sections/appendix.tex:1944:\\caption{Post-hoc power analysis ($n{=}23$, two-tailed, $\\alpha{=}0.05$). At this sample size, only large correlations ($\\rho{\\geq}0.5$) are detectable with adequate power.}\ndocs/paper/sections/appendix.tex:1960:\\noindent 80\\% power requires $n{\\approx}85$ for $\\rho{=}0.3$ and $n{\\approx}47$ for $\\rho{=}0.5$. The null result should be interpreted as absence of evidence for a large effect rather than evidence of absence.\ndocs/paper/sections/appendix.tex:2217:Qwen2.5-72B zero-shot exhibits the same gap: LP $\\rho$ drops without fine-tuning, structural signals generalize (VC $\\rho{=}0.416$ on Few-NERD), and degeneracy is model-family-dependent rather than scale-dependent (Qwen2.5: 31.7--46.2\\% vs.\\ Qwen3: 13.0\\%; Appendix~\\ref{app:cross_scale}). The capability ceiling persists from 4B to 72B.\ndocs/paper/sections/introduction.tex:20:Five quality estimation (QE) signals achieve rank correlations up to $\\rho{=}0.45$ and AUROC up to 0.82 with oracle F1, yet no signal outperforms greedy decoding on SciERC ($p{>}0.05$ for all comparisons).\ndocs/paper/sections/introduction.tex:31:We extend to Qwen2.5-72B zero-shot and GPT-5.5 zero-shot (50\\% degeneracy, SJ $\\rho{=}0.346$) to confirm the ceiling is not model-family-specific (\\S\\ref{sec:scaling}).\ndocs/paper/sections/introduction.tex:39:\\caption{Overview of the correlation-selection gap (diagnostic sequence, not causal chain). \\textbf{Left}: consistency signals estimate instance quality ($\\rho$ up to 0.45; Table~\\ref{tab:quality_estimation}). \\textbf{Center}: instance-level signals assign identical scores to all $N$ candidates, so selection cannot outperform greedy. \\textbf{Right}: LP-weighted entity construction ($\\theta{=}2/N$) bypasses the bottleneck ($+1.40$\\,pp on Few-NERD; \\S\\ref{sec:prescriptive}).}\ndocs/paper/sections/experiments_main.tex:43:On SciERC, structural signals lead (VC $\\rho{=}0.379$, SJ $0.360$) over LP ($0.205$); bootstrap CIs confirm the gap ($\\Delta\\rho{=}{+}0.155$; Appendix~\\ref{app:bootstrap_signal}).\ndocs/paper/sections/experiments_main.tex:45:At the signal-collapse boundary (WNUT-17, F1${\\approx}$42\\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\\rho{=}0.724$ at $N{=}16$, but conditional $\\rho{=}0.038$; Table~\\ref{tab:wnut}); LP shows the reverse (conditional $\\rho{=}0.350$; Figure~\\ref{fig:signal_heatmap}).\ndocs/paper/sections/experiments_main.tex:122:Construction and LP selection are complementary, governed by within-instance LP alignment $\\rho_{\\text{adj}}$ (Few-NERD $0.516$ favors both; SciERC $0.167$ favors construction only).",
    "numLines": 76
  }
}
```

</details>

---

### Assistant

_source line 41_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture. Let me also check the N=16 robustness table to see if those have higher ρ values. Let me look at the robustness table mentioned in the paper.

From the data I've already collected, here are all the ρ values from `analysis_unified_rho_full.json`:

**N=16 experiments:**
- LLaMA CoNLL seed42: SJ=0.4836, EM=0.4818, FK=0.4752, VC=0.4746


- LLaMA CoNLL seed123: SJ=0.4662, VC=0.4633, EM=0.4632, FK=0.4573
- LLaMA CoNLL seed456: SJ=0.4734, EM=0.4752, VC=0.4722, FK=0.4690
- Qwen SciERC seed42: VC=0.3993, SJ=0.3984
- Qwen SciERC seed123: SJ=0.4234
- Qwen SciERC seed456: VC=0.4449, SJ=0.4098

**N=8 experiments:**
- Qwen CoNLL seed42: EM

=0.4507, SJ=0.4357
- LLaMA CoNLL seed42: SJ=0.4314, EM=0.4306, FK=0.4277, VC=0.4256
- LLaMA CoNLL seed123: SJ=0.431, FK=0.426, EM=0.428, VC=0.42
- Qwen SciERC seed123: VC=0.4133
- LLaMA SciERC seed123: VC=0.4032

The peak performance across all these runs is SJ=0.4836 from LLaMA on CoNLL with N=16 and seed42. I'm realizing this is data from the earlier non-finetuned LLaMA and Qwen experiments, but the current paper actually uses Qwen3-8B with finetuning instead.

Looking at Table 1 in the paper, the finetuned models show different results: EM on CoNLL reaches ρ=0.451 with Qwen, SJ on CoNLL is ρ=0.431 for LLaMA and ρ=0.436 for Qwen, all using N=8 and seed42. The highest correlation in Table 1 is 0.451 for EM with Qwen. I need to figure out whether the MF4v2 experiments for the critical alpha table use the same setup as Table 1 or if they're based on different experimental conditions.

Looking at the full data from unified_rho_full.json, the N=8 setup (which is the paper's main configuration) peaks at EM CoNLL Qwen with ρ=0.4507, rounding to 0.45 as stated in the abstract. However, N=16 experiments show higher values like SJ LLaMA CoNLL reaching ρ=0.4836, which would round to 0.48. The WNUT-17 dataset shows even stronger results with VC reaching ρ=0.724 at N=16, though this appears to be a full-set correlation rather than a conditional one. I'm tracking down where the 0.472 EM value for LLaMA CoNLL comes from in the reviewer's concern. Looking at the N=16 results, I see values around 0.475-0.482 depending on the seed, but the N=8 primary setup maxes out lower at around 0.43. I need to check the robustness and multi-seed tables in the paper to see if there's a different reporting of these numbers that would explain the discrepancy.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "43a88b6a-8a15-4cad-94f7-cb8611e476da",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BiHBU5KNozAmSa3rx8zXb6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8730,
      "cache_read_input_tokens": 43628,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8730
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

Let me check the robustness table and appendix tables that might show N=16 ρ values.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "5b155e62-c49c-41a2-ae57-6883bcc2411d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BiHBU5KNozAmSa3rx8zXb6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8730,
      "cache_read_input_tokens": 43628,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8730
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

<details open><summary>🔧 Tool call — Grep · `toolu_01VwvcxPs3ueXo4rb7YUwVLh`</summary>

```json
{
  "pattern": "tab:robustness|tab:multiseed|N.*16.*rho|n16.*rho",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "4ceffba6-adf6-491b-9b82-bafa43681b35",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BiHBU5KNozAmSa3rx8zXb6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8730,
      "cache_read_input_tokens": 43628,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8730
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

_source line 44 · 2026-05-21T12:01:37.131Z_

<details><summary>↩ Tool result · `toolu_01VwvcxPs3ueXo4rb7YUwVLh`</summary>

```text
docs/paper/sections/experiments.tex:25:\caption{NER quality estimation ($\rho$ and AUROC; $N{=}8$, primary seed${=}42$; 3-seed $\sigma{\leq}0.026$ in Table~\ref{tab:multiseed}). AUROC binarizes at per-dataset median F1. Best in \textbf{bold}. RE in Appendix~\ref{app:re_extension}; $N{=}16$ in Table~\ref{tab:robustness}.}
docs/paper/sections/experiments.tex:48:At the signal-collapse boundary (WNUT-17, macro F1${\approx}$42\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\rho{=}0.724$ at $N{=}16$, but conditional $\rho{=}0.038$; Table~\ref{tab:wnut}); LP shows the reverse (conditional $\rho{=}0.350$; Figure~\ref{fig:signal_heatmap}).
docs/paper/sections/experiments.tex:103:The pattern matches observations: Few-NERD (low degeneracy, strong alignment) yields $+1.39$\,pp; SciERC (weak alignment) $+0.04{\pm}0.48$\,pp (3-seed; Table~\ref{tab:multiseed}); CoNLL (high degeneracy) none; WNUT-17 shows reversed LP ($\rho{=}{-}0.446$) yet QE remains effective (VC $\rho{=}0.724$, $N{=}16$; Table~\ref{tab:wnut}).
docs/paper/sections/experiments.tex:113:\caption{LP selection across datasets (Qwen3-8B, $N{=}8$, $T{=}1.0$, gold-filtered). Few-NERD/CoNLL: 3-seed means; SciERC: single-seed (3-seed in Table~\ref{tab:multiseed}). $p$: paired bootstrap.}
docs/paper/sections/experiments.tex:146:Consistency signals are robust across $T{\in}\{0.7, 1.0\}$ with sublinear $N$-scaling gains (Table~\ref{tab:robustness}); signal rankings are stable across seeds ($W{=}1.0$; Table~\ref{tab:ranking-stability}). NER calibration is reasonable (ECE 0.069--0.096; Appendix~\ref{app:calibration}).
docs/paper/sections/experiments.tex:247:Construction and LP selection are complementary, governed by $\rho_{\text{adj}}$: Few-NERD ($\rho_{\text{adj}}{=}0.516$) favors both, while SciERC ($\rho_{\text{adj}}{=}0.167$) favors construction only. A three-way routing protocol ($\rho_{\text{adj}} \geq 0.3$: LP; $<0.3$ with positive construction: construction; else: greedy) is stable across $\tau{\in}[0.2, 0.4]$.
docs/paper/sections/checklist.tex:54:Yes. We report multi-seed results (3 seeds; $\sigma$ in Table~\ref{tab:multiseed}), bootstrap 95\% confidence intervals (Tables~\ref{tab:selection}, \ref{tab:fewnerd_full}), paired bootstrap $p$-values throughout, and minimum detectable effect sizes (Section~\ref{sec:selection_gap}). Tables clearly indicate whether values are single-seed, multi-seed means, or confidence intervals.
docs/paper/sections/appendix.tex:38:\label{tab:robustness}
docs/paper/sections/appendix.tex:81:Increasing from $N{=}8$ to $N{=}16$ improves SJ on Qwen SciERC NER: $\rho$ rises from 0.360 to $0.411{\pm}0.010$ (three seeds: 0.398, 0.423, 0.410), a gain of $+0.047$.
docs/paper/sections/appendix.tex:92:[Omitted long matching line]
docs/paper/sections/appendix.tex:201:At $N{=}16$, the divergence persists: SJ maintains $\rho{=}0.308$ on conditional RE while LP drops to $\rho{=}{-}0.026$.
docs/paper/sections/appendix.tex:202:EM ranks first across all four tested conditional configurations: SciERC NER ($\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\rho{=}0.466$), CoNLL LLaMA 3-seed ($\rho{=}0.462$), and SciERC RE ($\rho{=}0.417$). This holds despite full-set rankings ranging from \#1 (CoNLL Qwen) to \#5 (SciERC RE).
docs/paper/sections/appendix.tex:213:\caption{Quality estimation on WNUT-17 (Qwen, $N{=}16$, $T{=}1.0$, $n{=}689$). Cond: non-zero F1 instances ($n{=}334$). Full-set $\rho$ reflects binary success prediction; conditional $\rho$ measures quality gradation. LP's conditional $\rho$ is highest despite negative full-set $\rho$.}
docs/paper/sections/appendix.tex:257:Our $N{=}8$ and $N{=}16$ comparisons (Table~\ref{tab:robustness}) characterize the marginal value of additional samples for test-time scaling \cite{brown2024monkeys, snell2025scaling}.
docs/paper/sections/appendix.tex:258:For quality estimation, structural signals benefit consistently but sublinearly: SJ $\rho$ improves by $+0.047$ (Qwen SciERC, 3-seed mean) and $+0.032$ (LLaMA CoNLL, 3-seed mean) when doubling from $N{=}8$ to $N{=}16$, while log-probability is approximately $N$-invariant ($\Delta\rho{\leq}0.021$).
docs/paper/sections/appendix.tex:259:Structural signals use $\binom{N}{2}$ pairwise comparisons (28 pairs at $N{=}8$, 120 at $N{=}16$), but the $\rho$ improvement is far less than proportional, each additional comparison yields diminishing information.
docs/paper/sections/appendix.tex:311:On SciERC NER ($n{=}529$), SJ--FK ($\Delta\rho{=}0.147$--$0.160$, all $p{\leq}0.002$) and VC--FK ($\Delta\rho{=}0.138$--$0.188$, all $p{\leq}0.003$) are clearly significant across all three seeds; EM--FK is seed-dependent ($\Delta\rho{=}0.054$--$0.093$, $p{=}0.048$--$0.15$).
docs/paper/sections/appendix.tex:650:Table~\ref{tab:multiseed} reports quality estimation metrics across three random seeds for both model families on SciERC ($N{=}8$, $T{=}1.0$).
docs/paper/sections/appendix.tex:659:\label{tab:multiseed}
docs/paper/sections/appendix.tex:932:RE quality estimation is reported in Table~\ref{tab:multiseed} (3-seed means).
docs/paper/sections/appendix.tex:1555:The $T{=}0.7$ and $T{=}1.0$ comparison in Table~\ref{tab:robustness} is consistent with the trends reported here.
docs/paper/sections/appendix.tex:2238:All experiments use open-weight models (Qwen3-8B, LLaMA-3.1-8B, Qwen3-4B, Qwen2.5-7B, Qwen2.5-72B) and public benchmarks. Multi-seed stability ($\sigma{\leq}0.026$ for QE; Table~\ref{tab:multiseed}) and full hyperparameter sweeps are reported. Code, checkpoints, and per-seed results will be released upon acceptance.
docs/paper/sections/experiments_main.tex:22:\caption{NER quality estimation ($\rho$ and AUROC; $N{=}8$, primary seed${=}42$; 3-seed $\sigma{\leq}0.026$ in Table~\ref{tab:multiseed}). AUROC binarizes at per-dataset median F1. Best in \textbf{bold}. RE in Appendix~\ref{app:re_extension}; $N{=}16$ in Table~\ref{tab:robustness}.}
docs/paper/sections/experiments_main.tex:45:At the signal-collapse boundary (WNUT-17, F1${\approx}$42\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\rho{=}0.724$ at $N{=}16$, but conditional $\rho{=}0.038$; Table~\ref{tab:wnut}); LP shows the reverse (conditional $\rho{=}0.350$; Figure~\ref{fig:signal_heatmap}).
docs/paper/sections/experiments_main.tex:85:Signal rankings are robust across temperatures, seeds ($W{=}1.0$), and $N$ (Table~\ref{tab:robustness}); NER calibration is reasonable (ECE 0.069--0.096; Appendix~\ref{app:calibration}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "4d966fda-c756-45d1-a5ee-d0dbec0f6455",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:25:\\caption{NER quality estimation ($\\rho$ and AUROC; $N{=}8$, primary seed${=}42$; 3-seed $\\sigma{\\leq}0.026$ in Table~\\ref{tab:multiseed}). AUROC binarizes at per-dataset median F1. Best in \\textbf{bold}. RE in Appendix~\\ref{app:re_extension}; $N{=}16$ in Table~\\ref{tab:robustness}.}\ndocs/paper/sections/experiments.tex:48:At the signal-collapse boundary (WNUT-17, macro F1${\\approx}$42\\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\\rho{=}0.724$ at $N{=}16$, but conditional $\\rho{=}0.038$; Table~\\ref{tab:wnut}); LP shows the reverse (conditional $\\rho{=}0.350$; Figure~\\ref{fig:signal_heatmap}).\ndocs/paper/sections/experiments.tex:103:The pattern matches observations: Few-NERD (low degeneracy, strong alignment) yields $+1.39$\\,pp; SciERC (weak alignment) $+0.04{\\pm}0.48$\\,pp (3-seed; Table~\\ref{tab:multiseed}); CoNLL (high degeneracy) none; WNUT-17 shows reversed LP ($\\rho{=}{-}0.446$) yet QE remains effective (VC $\\rho{=}0.724$, $N{=}16$; Table~\\ref{tab:wnut}).\ndocs/paper/sections/experiments.tex:113:\\caption{LP selection across datasets (Qwen3-8B, $N{=}8$, $T{=}1.0$, gold-filtered). Few-NERD/CoNLL: 3-seed means; SciERC: single-seed (3-seed in Table~\\ref{tab:multiseed}). $p$: paired bootstrap.}\ndocs/paper/sections/experiments.tex:146:Consistency signals are robust across $T{\\in}\\{0.7, 1.0\\}$ with sublinear $N$-scaling gains (Table~\\ref{tab:robustness}); signal rankings are stable across seeds ($W{=}1.0$; Table~\\ref{tab:ranking-stability}). NER calibration is reasonable (ECE 0.069--0.096; Appendix~\\ref{app:calibration}).\ndocs/paper/sections/experiments.tex:247:Construction and LP selection are complementary, governed by $\\rho_{\\text{adj}}$: Few-NERD ($\\rho_{\\text{adj}}{=}0.516$) favors both, while SciERC ($\\rho_{\\text{adj}}{=}0.167$) favors construction only. A three-way routing protocol ($\\rho_{\\text{adj}} \\geq 0.3$: LP; $<0.3$ with positive construction: construction; else: greedy) is stable across $\\tau{\\in}[0.2, 0.4]$.\ndocs/paper/sections/checklist.tex:54:Yes. We report multi-seed results (3 seeds; $\\sigma$ in Table~\\ref{tab:multiseed}), bootstrap 95\\% confidence intervals (Tables~\\ref{tab:selection}, \\ref{tab:fewnerd_full}), paired bootstrap $p$-values throughout, and minimum detectable effect sizes (Section~\\ref{sec:selection_gap}). Tables clearly indicate whether values are single-seed, multi-seed means, or confidence intervals.\ndocs/paper/sections/appendix.tex:38:\\label{tab:robustness}\ndocs/paper/sections/appendix.tex:81:Increasing from $N{=}8$ to $N{=}16$ improves SJ on Qwen SciERC NER: $\\rho$ rises from 0.360 to $0.411{\\pm}0.010$ (three seeds: 0.398, 0.423, 0.410), a gain of $+0.047$.\ndocs/paper/sections/appendix.tex:92:[Omitted long matching line]\ndocs/paper/sections/appendix.tex:201:At $N{=}16$, the divergence persists: SJ maintains $\\rho{=}0.308$ on conditional RE while LP drops to $\\rho{=}{-}0.026$.\ndocs/paper/sections/appendix.tex:202:EM ranks first across all four tested conditional configurations: SciERC NER ($\\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\\rho{=}0.466$), CoNLL LLaMA 3-seed ($\\rho{=}0.462$), and SciERC RE ($\\rho{=}0.417$). This holds despite full-set rankings ranging from \\#1 (CoNLL Qwen) to \\#5 (SciERC RE).\ndocs/paper/sections/appendix.tex:213:\\caption{Quality estimation on WNUT-17 (Qwen, $N{=}16$, $T{=}1.0$, $n{=}689$). Cond: non-zero F1 instances ($n{=}334$). Full-set $\\rho$ reflects binary success prediction; conditional $\\rho$ measures quality gradation. LP's conditional $\\rho$ is highest despite negative full-set $\\rho$.}\ndocs/paper/sections/appendix.tex:257:Our $N{=}8$ and $N{=}16$ comparisons (Table~\\ref{tab:robustness}) characterize the marginal value of additional samples for test-time scaling \\cite{brown2024monkeys, snell2025scaling}.\ndocs/paper/sections/appendix.tex:258:For quality estimation, structural signals benefit consistently but sublinearly: SJ $\\rho$ improves by $+0.047$ (Qwen SciERC, 3-seed mean) and $+0.032$ (LLaMA CoNLL, 3-seed mean) when doubling from $N{=}8$ to $N{=}16$, while log-probability is approximately $N$-invariant ($\\Delta\\rho{\\leq}0.021$).\ndocs/paper/sections/appendix.tex:259:Structural signals use $\\binom{N}{2}$ pairwise comparisons (28 pairs at $N{=}8$, 120 at $N{=}16$), but the $\\rho$ improvement is far less than proportional, each additional comparison yields diminishing information.\ndocs/paper/sections/appendix.tex:311:On SciERC NER ($n{=}529$), SJ--FK ($\\Delta\\rho{=}0.147$--$0.160$, all $p{\\leq}0.002$) and VC--FK ($\\Delta\\rho{=}0.138$--$0.188$, all $p{\\leq}0.003$) are clearly significant across all three seeds; EM--FK is seed-dependent ($\\Delta\\rho{=}0.054$--$0.093$, $p{=}0.048$--$0.15$).\ndocs/paper/sections/appendix.tex:650:Table~\\ref{tab:multiseed} reports quality estimation metrics across three random seeds for both model families on SciERC ($N{=}8$, $T{=}1.0$).\ndocs/paper/sections/appendix.tex:659:\\label{tab:multiseed}\ndocs/paper/sections/appendix.tex:932:RE quality estimation is reported in Table~\\ref{tab:multiseed} (3-seed means).\ndocs/paper/sections/appendix.tex:1555:The $T{=}0.7$ and $T{=}1.0$ comparison in Table~\\ref{tab:robustness} is consistent with the trends reported here.\ndocs/paper/sections/appendix.tex:2238:All experiments use open-weight models (Qwen3-8B, LLaMA-3.1-8B, Qwen3-4B, Qwen2.5-7B, Qwen2.5-72B) and public benchmarks. Multi-seed stability ($\\sigma{\\leq}0.026$ for QE; Table~\\ref{tab:multiseed}) and full hyperparameter sweeps are reported. Code, checkpoints, and per-seed results will be released upon acceptance.\ndocs/paper/sections/experiments_main.tex:22:\\caption{NER quality estimation ($\\rho$ and AUROC; $N{=}8$, primary seed${=}42$; 3-seed $\\sigma{\\leq}0.026$ in Table~\\ref{tab:multiseed}). AUROC binarizes at per-dataset median F1. Best in \\textbf{bold}. RE in Appendix~\\ref{app:re_extension}; $N{=}16$ in Table~\\ref{tab:robustness}.}\ndocs/paper/sections/experiments_main.tex:45:At the signal-collapse boundary (WNUT-17, F1${\\approx}$42\\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\\rho{=}0.724$ at $N{=}16$, but conditional $\\rho{=}0.038$; Table~\\ref{tab:wnut}); LP shows the reverse (conditional $\\rho{=}0.350$; Figure~\\ref{fig:signal_heatmap}).\ndocs/paper/sections/experiments_main.tex:85:Signal rankings are robust across temperatures, seeds ($W{=}1.0$), and $N$ (Table~\\ref{tab:robustness}); NER calibration is reasonable (ECE 0.069--0.096; Appendix~\\ref{app:calibration}).",
    "numLines": 25
  }
}
```

</details>

---

### Tool call

_source line 45_

<details open><summary>🔧 Tool call — Read · `toolu_013wxfYwUHJcwAo4821j26qQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "limit": 300
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "6d55ad3c-dbd5-4f7c-88f0-769a5760ebd1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BiHBU5KNozAmSa3rx8zXb6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8730,
      "cache_read_input_tokens": 43628,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8730
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

_source line 46 · 2026-05-21T12:01:37.689Z_

<details><summary>↩ Tool result · `toolu_013wxfYwUHJcwAo4821j26qQ`</summary>

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
104	\resizebox{\columnwidth}{!}{
105	\begin{tabular}{lrcccc}
106	\toprule
107	Config & $n$ & FK mean & 95\% CI & $t$ & Split-half $r$ \\
108	\midrule
109	SciERC (Qwen) & 529 & 0.402 & [0.376, 0.428] & 30.8 & 0.395 \\
110	CoNLL (LLaMA) & 2{,}756 & 0.927 & [0.919, 0.935] & 225.9 & 0.578 \\
111	CoNLL (Qwen) & 2{,}756 & 0.720 & [0.706, 0.734] & 102.1 & 0.520 \\
112	\bottomrule
113	\end{tabular}
114	}
115	\end{table}
116	
117	Table~\ref{tab:fk_independence} reports the results.
118	All configurations reject the independence null at $p{<}0.001$ ($n{=}529$--$2{,}756$), FK captures genuine inter-sample agreement rather than chance label co-occurrence.
119	Split-half reliability ranges from $r{=}0.395$ (SciERC) to $r{=}0.578$ (CoNLL LLaMA), moderate stability: FK estimates from half the samples correlate positively with those from the other half, though the SciERC value suggests noisier estimation on harder tasks with fewer samples.
120	The higher FK means on CoNLL ($0.720$--$0.927$) vs.\ SciERC ($0.402$) mirror the difficulty gradient observed in the main quality estimation results.
121	
122	\section{Calibration Analysis}\label{app:calibration}
123	
124	\begin{figure*}[t]
125	\centering
126	\includegraphics[width=\textwidth]{fig_reliability}
127	\caption{Reliability diagrams on SciERC ($N{=}8$, $T{=}1.0$). Top: mean F1 vs.\ binned confidence; bottom: instance counts per bin. Left: NER; right: RE. NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE shows greater miscalibration (ECE 0.109--0.339), RE calibration remains challenging for compound extraction tasks.}
128	\label{fig:reliability}
129	\end{figure*}
130	
131	Reliability diagrams use 10 equal-width bins.
132	NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE exhibits greater miscalibration (ECE 0.109--0.339), translating consistency scores into calibrated confidence estimates is feasible for NER but remains challenging for compound extraction tasks.
133	
134	\section{Additional Analyses}\label{app:additional}
135	
136	\begin{figure*}[t]
137	\centering
138	\includegraphics[width=\textwidth]{fig_signal_heatmap}
139	\caption{Quality estimation heatmap (Spearman $\rho$) across five signals and four configurations. Left: full evaluation set; right: conditional set (non-zero F1 instances). On the full set, structural signals dominate on SciERC NER while all signals converge on CoNLL. On the conditional set, EM emerges as the strongest signal on both NER ($\rho{=}0.360$) and RE ($\rho{=}0.417$), while LP RE collapses to near-zero ($\rho{=}0.011$).}
140	\label{fig:signal_heatmap}
141	\end{figure*}
142	
143	\paragraph{Per-relation diagnostic.}
144	RE signal degradation is relation-specific.
145	\textsc{Feature-Of} has near-zero correlation ($\rho{=}0.004$), while \textsc{Hyponym-Of} achieves $\rho{=}0.646$.
146	The primary bottleneck is entity span errors, which account for 55.5\% of RE false negatives. This is a prerequisite failure that consistency signals cannot detect, as they measure agreement among equally incorrect extractions.
147	We note that RE analysis relies on a single dataset (SciERC); generalization to other RE benchmarks remains to be validated.
148	
149	\paragraph{Capability stratification.}
150	For NER, SJ effectiveness scales with structural complexity: on SciERC instances with 6+ entities, $\rho{=}0.547$, compared to $\rho{=}0.415$ for 1--2 entities.
151	The SJ advantage over LP remains stable across sentence-length quartiles ($\Delta\rho{\approx}0.08$--$0.20$).
152	For RE, SJ $\rho$ increases monotonically with sentence length (Q1: 0.110 $\to$ Q4: 0.473; Fisher $z$-test $p{=}0.004$): longer, more relation-dense sentences provide richer structure for consistency-based estimation.
153	Both proxies are weakly correlated with F1 ($|r|{<}0.15$), they capture input complexity rather than directly predicting output quality; however, entity count and sentence length are themselves moderately correlated ($\rho{=}0.650$), so they reflect overlapping rather than independent complexity dimensions.
154	For RE, entity count and relation count are strongly correlated ($\rho{=}0.769$) and thus reflect a single structural complexity dimension rather than independent axes.
155	On the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\rho{=}0.630$, LP $\rho{=}0.554$, and SJ $\rho{=}0.502$, all far above the full-set levels.
156	Richer relational structure provides more signal for consistency-based estimation, complementing the task-level boundary established by WNUT-17: structural signals are most effective within a ``sweet spot'' of sufficient model capability and sufficient output complexity.
157	
158	\paragraph{Length vs.\ log-probability.}
159	Figure~\ref{fig:length_logprob_scatter} shows that mean log-probability is weakly positively correlated with output length (NER: $\rho{=}0.386$, $n{=}4{,}232$; RE: $\rho{=}0.326$, $n{=}3{,}176$), ruling out length-penalty confounding as an explanation for LP's selection failure: longer outputs receive \textit{higher}, not lower, token-averaged log-probability under constrained decoding.
160	
161	\begin{figure}[t]
162	\centering
163	\includegraphics[width=\columnwidth]{fig_length_logprob_scatter}
164	\caption{Output length vs.\ mean log-probability on SciERC ($N{=}8$, $T{=}1.0$). Positive correlations (NER: $\rho{=}0.386$; RE: $\rho{=}0.326$) rule out length-penalty confounding.}
165	\label{fig:length_logprob_scatter}
166	\end{figure}
167	
168	\paragraph{Evaluation circularity and LOO-SJ equivalence.}
169	Consensus-proximity selection chooses $\hat{y} = \arg\max_{y_i} \sum_{j \neq i} \text{SJ}(y_i, y_j)$.
170	Leave-one-out SJ (LOO-SJ) for sample $y_i$ is $\text{LOO-SJ}_i = \frac{1}{N-1}\sum_{j \neq i} \text{SJ}(y_i, y_j)$.
171	Since the $\frac{1}{N-1}$ constant is shared across all candidates within an instance, $\arg\max_{y_i} \text{LOO-SJ}_i = \arg\max_{y_i} \sum_{j \neq i} \text{SJ}(y_i, y_j)$; the two selection rules are equivalent.
172	Standard (non-LOO) SJ adds the self-comparison term $\text{SJ}(y_i, y_i) = 1$ to each candidate, which is constant and thus does not affect ranking.
173	Empirically, LOO-SJ yields $\Delta\rho{=}{-}0.014$ relative to standard SJ (a correlation-level difference), with a maximum per-instance score difference of $3.1{\times}10^{-4}$ (negligible at the individual prediction level).
174	Evaluation circularity is negligible.
175	
176	\paragraph{SJ normalizer robustness.}
177	Equation~\ref{eq:sj} uses $\max(|g_i|, |g_j|)$ as the denominator; an alternative is the union size $|g_i \cup g_j|$.
178	Table~\ref{tab:sj_normalizer} compares the two normalizers across all six model--dataset combinations ($N{=}8$, $T{=}1.0$, seed${=}42$): $|\Delta\rho|{<}0.01$ in every case, the choice between max and union normalization does not affect conclusions.
179	
180	\begin{table}[h]
181	\centering
182	\small
183	\caption{SJ normalizer comparison (Spearman $\rho$; $N{=}8$, $T{=}1.0$, seed${=}42$). Max: $\max(|g_i|,|g_j|)$; Union: $|g_i \cup g_j|$.}
184	\label{tab:sj_normalizer}
185	\begin{tabular}{@{}ll ccc@{}}
186	\toprule
187	Dataset & Model & $\rho$(max) & $\rho$(union) & $\Delta\rho$ \\
188	\midrule
189	CoNLL & Qwen3-8B & .436 & .438 & $-$.002 \\
190	CoNLL & Qwen3-4B & .422 & .421 & $+$.000 \\
191	CoNLL & LLaMA-8B & .431 & .432 & $-$.000 \\
192	SciERC & Qwen3-8B & .360 & .365 & $-$.005 \\
193	SciERC & Qwen3-4B & .422 & .423 & $-$.001 \\
194	SciERC & LLaMA-8B & .363 & .372 & $-$.009 \\
195	\bottomrule
196	\end{tabular}
197	\end{table}
198	
199	\paragraph{Conditional filtering details.}
200	On LLaMA conditional RE (non-zero F1 instances), SJ recovers to $\rho{=}0.405$ while FK drops to $\rho{=}0.259$, consistent with the NER structural advantage; on full-set RE, however, the SJ--FK difference is non-significant ($\Delta\rho{=}{-}0.005$, $p{=}0.53$; preliminary).
201	At $N{=}16$, the divergence persists: SJ maintains $\rho{=}0.308$ on conditional RE while LP drops to $\rho{=}{-}0.026$.
202	EM ranks first across all four tested conditional configurations: SciERC NER ($\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\rho{=}0.466$), CoNLL LLaMA 3-seed ($\rho{=}0.462$), and SciERC RE ($\rho{=}0.417$). This holds despite full-set rankings ranging from \#1 (CoNLL Qwen) to \#5 (SciERC RE).
203	On the full set, EM is diluted by trivial agreement: instances where all $N$ samples produce identical (possibly incorrect) outputs receive EM${=}1$ regardless of quality, compressing the signal's dynamic range.
204	On the conditional set, where the model demonstrably produces varied outputs, exact agreement becomes the strongest quality signal.
205	The margin over SJ is largest on RE ($\Delta\rho{=}{+}0.171$), where compound extraction decisions amplify output variability, and smallest on CoNLL LLaMA ($\Delta\rho{=}{+}0.002$), where all signals converge near $\rho{\approx}0.46$.
206	
207	\paragraph{WNUT-17 full signal analysis.}
208	Table~\ref{tab:wnut} reports all five signals on WNUT-17 with full-set and conditional $\rho$.
209	
210	\begin{table}[t]
211	\centering
212	\small
213	\caption{Quality estimation on WNUT-17 (Qwen, $N{=}16$, $T{=}1.0$, $n{=}689$). Cond: non-zero F1 instances ($n{=}334$). Full-set $\rho$ reflects binary success prediction; conditional $\rho$ measures quality gradation. LP's conditional $\rho$ is highest despite negative full-set $\rho$.}
214	\label{tab:wnut}
215	\begin{tabular}{lcccc}
216	\toprule
217	Signal & $\rho$ & AUROC & Cond.\ $\rho$ & Cond.\ $p$ \\
218	\midrule
219	VC      & .724 & .913 & .038 & .487 \\
220	FK      & .125 & .555 & .169 & .002 \\
221	SJ      & .089 & .517 & .288 & ${<}$1e-7 \\
222	EM      & .050 & .487 & .333 & ${<}$1e-9 \\
223	LP & $-$.410 & .219 & .350 & ${<}$1e-10 \\
224	\bottomrule
225	\end{tabular}
226	\end{table}
227	The full-set $p$-values are: VC ${<}$1e-112, FK $p{=}0.001$, SJ $p{=}0.020$, EM $p{=}0.194$, LP ${<}$1e-28.
228	VC's high full-set $\rho{=}0.724$ is entirely driven by the zero/non-zero boundary (conditional $\rho{=}0.038$, $p{=}0.49$), while LP's conditional $\rho{=}0.350$ is the highest among all signals on the non-zero subset, full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.
229	
230	\paragraph{Cross-configuration selection analysis.}
231	Table~\ref{tab:cross_selection} extends the selection analysis to five additional configurations.
232	On LLaMA SciERC, where output diversity remains substantial (18\% identical outputs, 39\% unique), LP achieves the highest selection F1 (0.652) at $N{=}8$ but still falls within bootstrap noise of single-sample (0.646), replicating the gap observed on Qwen SciERC (Table~\ref{tab:selection}).
233	On LLaMA FewNERD ($n{=}32{,}565$, 3-seed mean), LP is the only signal with positive selection ($+0.36$~pp), confirming LP as the most robust selection signal across model families (Qwen FewNERD: $+1.39$~pp, Table~\ref{tab:fewnerd}). All structural signals degrade selection (VC $-2.39$~pp, SJ $-0.52$~pp), consistent with the Qwen pattern. LLaMA FewNERD degeneracy ($23.4{\pm}4.7$\%, 3 seeds) is higher than Qwen ($13.0$\%), illustrating the capability-diversity tension: LLaMA achieves stronger greedy F1 ($0.784$ vs.\ $0.748$, $+3.6$~pp) but at the cost of higher degeneracy ($+10.4$~pp) and reduced oracle headroom ($10.0$ vs.\ $12.4$~pp).
234	On CoNLL, 48--87\% of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect (single-sample F1 ${\approx}$0.91--0.92) rather than signal failure, and selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.
235	
236	\begin{table*}[t]
237	\centering
238	\small
239	\caption{Best-of-$N$ selection F1 (macro, instance-averaged) across configurations ($T{=}1.0$, 3-seed mean). Best non-oracle signal per row in \textbf{bold}. LP is the only signal with positive selection on both FewNERD configurations (Qwen $+1.39$~pp, Table~\ref{tab:fewnerd}; LLaMA $+0.36$~pp). At $N{=}16$ on LLaMA CoNLL, VC achieves small but significant gains ($+0.28$~pp, $p{<}0.03$; see text below). CoNLL shows especially tight clustering where greedy already exceeds 0.90.}
240	\label{tab:cross_selection}
241	\begin{tabular}{llccccccc}
242	\toprule
243	Config & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\
244	\midrule
245	LLaMA/SciERC $N{=}8$ & 529 & .646 & .778 & .643 & .639 & .634 & \textbf{.652} & .633 \\
246	LLaMA/SciERC $N{=}16$ & 529 & .645 & .806 & \textbf{.649} & \textbf{.649} & .640 & .646 & .640 \\
247	\addlinespace
248	LLaMA/FewNERD $N{=}8$ & 32{,}565 & .784 & .884 & .779 & .779 & .774 & \textbf{.788} & .760 \\
249	\addlinespace
250	Qwen/CoNLL $N{=}8$ & 2{,}756 & .908 & .948 & \textbf{.899} & .893 & .898 & .897 & .895 \\
251	LLaMA/CoNLL $N{=}8$ & 2{,}756 & .924 & .943 & .924 & \textbf{.925} & .924 & .924 & .923 \\
252	\bottomrule
253	\end{tabular}
254	\end{table*}
255	
256	\paragraph{Diminishing returns of $N$-scaling.}
257	Our $N{=}8$ and $N{=}16$ comparisons (Table~\ref{tab:robustness}) characterize the marginal value of additional samples for test-time scaling \cite{brown2024monkeys, snell2025scaling}.
258	For quality estimation, structural signals benefit consistently but sublinearly: SJ $\rho$ improves by $+0.047$ (Qwen SciERC, 3-seed mean) and $+0.032$ (LLaMA CoNLL, 3-seed mean) when doubling from $N{=}8$ to $N{=}16$, while log-probability is approximately $N$-invariant ($\Delta\rho{\leq}0.021$).
259	Structural signals use $\binom{N}{2}$ pairwise comparisons (28 pairs at $N{=}8$, 120 at $N{=}16$), but the $\rho$ improvement is far less than proportional, each additional comparison yields diminishing information.
260	This asymmetry gives structural signals a relative advantage in the compute-constrained regime: at $N{=}8$, SJ already achieves $\rho{=}0.431$ on LLaMA CoNLL (vs.\ LP $\rho{=}0.307$, $\Delta{=}{+}0.124$), and the gap \textit{widens} at $N{=}16$ ($\Delta{=}{+}0.163$) because structural signals continue to benefit from additional pairwise evidence while LP does not.
261	For sample selection, additional samples increase the oracle upper bound (more draws raise the probability of a high-quality candidate), but signal-based selection remains flat because the selector's inability to identify the best candidate is a granularity limitation, not a sample size limitation.
262	The practical implication is that $N{=}8$ captures most of the achievable quality estimation benefit; further scaling widens rather than closes the correlation-selection gap absent stronger per-sample selectors.
263	
264	\paragraph{$N{=}16$ CoNLL selection: small but significant.}
265	While quality estimation benefits sublinearly from $N$-scaling, selection behavior at $N{=}16$ reveals a nuanced exception on LLaMA CoNLL.
266	VC achieves the largest gain over single-sample ($+0.28$~pp, $p{=}0.003$--$0.027$ across 3 seeds, all significant), with SJ, FK, and EM at $+0.22$--$0.23$~pp and LP at $+0.12$~pp (2/3 seeds significant).
267	These gains are statistically significant but practically minimal: oracle headroom at $N{=}16$ is only 2.5~pp, so VC captures approximately 10\% of the available headroom.
268	This reinforces the primary finding: even under the most favorable conditions (high baseline performance, more candidates, and aggregated multi-seed evidence), signal-based selection recovers only a fraction of the oracle headroom available.
269	
270	\section{Bootstrap CI for Signal Comparisons}\label{app:bootstrap_signal}
271	
272	Table~\ref{tab:bootstrap_signal_ci} reports bootstrap confidence intervals for individual signal $\rho$ and pairwise $\Delta\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$).
273	The SJ--LP gap ($\Delta\rho{=}{+}0.155$) is clearly significant, the structural advantage reported in \S\ref{sec:qe_results} is robust.
274	The VC--SJ gap ($\Delta\rho{=}{+}0.019$) is not significant; these two structural signals perform comparably.
275	The SJ--EM gap ($\Delta\rho{=}{+}0.065$) is borderline significant, with the CI lower bound at $+0.003$ and upper bound at $+0.130$.
276	
277	\begin{table}[t]
278	\centering
279	\small
280	\caption{Bootstrap 95\% CIs for signal $\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$). Top: individual signals. Bottom: pairwise $\Delta\rho$; ``Sig.'' indicates whether the 95\% CI excludes zero.}
281	\label{tab:bootstrap_signal_ci}
282	\begin{tabular}{lcc}
283	\toprule
284	Signal & $\rho$ & 95\% CI \\
285	\midrule
286	VC & +0.379 & [+0.299, +0.456] \\
287	SJ & +0.360 & [+0.277, +0.437] \\
288	EM & +0.295 & [+0.212, +0.371] \\
289	FK & +0.267 & [+0.176, +0.354] \\
290	LP & +0.205 & [+0.119, +0.291] \\
291	\bottomrule
292	\end{tabular}
293	
294	\vspace{0.5em}
295	
296	\begin{tabular}{lccc}
297	\toprule
298	Comparison & $\Delta\rho$ & 95\% CI & Sig. \\
299	\midrule
300	SJ $-$ LP & +0.155 & [+0.074, +0.234] & Yes \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "4301243d-5467-4e3b-83be-f048b2217e7a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "\\section{Notation}\\label{app:notation}\n\nTable~\\ref{tab:notation} summarizes the notation used throughout the paper.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{cl}\n\\toprule\nSymbol & Meaning \\\\\n\\midrule\n$\\mathcal{M}$ & Language model \\\\\n$x$ & Input instance \\\\\n$y_i$ & $i$-th stochastic sample \\\\\n$N$ & Number of samples \\\\\n$T$ & Sampling temperature \\\\\n$c(\\cdot)$ & Confidence signal \\\\\nSJ & Soft Jaccard similarity \\\\\nFK & Fleiss' $\\kappa$ \\\\\nEM & Exact-match voting rate \\\\\nVC ($c_{\\mathrm{vc}}$) & Entity voting confidence \\\\\nLP ($c_{\\mathrm{lp}}$) & Log-probability (mean token log-likelihood) \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Notation used throughout the paper.}\n\\label{tab:notation}\n\\end{table}\n\n\\section{Robustness Analysis}\\label{app:robustness}\n\nWe exclude instances with empty gold annotations from all correlation analyses (CoNLL: 697/3{,}453 instances, 20.2\\%; SciERC: 22/551, 4.0\\%).\nFor these instances, F1 is trivially zero regardless of prediction quality, and consistency signals reflect agreement on the empty set rather than extraction quality. Including them inflates or deflates Spearman $\\rho$ depending on signal behavior at the boundary.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Signal robustness across configurations (Spearman $\\rho$). Top: temperature on Qwen SciERC. Middle: sample size on Qwen SciERC. Bottom: transfer across model families (both 8B) (LLaMA CoNLL $N{=}16$, 3-seed mean $\\pm\\sigma$). $^\\dagger$Mean over 3 seeds ($\\sigma{=}0.013$; individual: 0.398, 0.423, 0.410). $\\sigma$ computed as sample standard deviation.}\n\\label{tab:robustness}\n\\begin{tabular}{llcc}\n\\toprule\n& & NER $\\rho$ & RE $\\rho$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Temperature} (Qwen SciERC, $N{=}8$)} \\\\\n\\quad SJ & $T{=}0.7$ & 0.364 & 0.234 \\\\\n\\quad SJ & $T{=}1.0$ & 0.360 & 0.250 \\\\\n\\quad FK & $T{=}0.7$ & 0.289 & 0.184 \\\\\n\\quad FK & $T{=}1.0$ & 0.267 & 0.275 \\\\\n\\quad LP & $T{=}0.7$ & 0.249 & --- \\\\\n\\quad LP & $T{=}1.0$ & 0.205 & 0.266 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Sample size} (Qwen SciERC, $T{=}1.0$)} \\\\\n\\quad SJ & $N{=}8$  & 0.360 & 0.250 \\\\\n\\quad SJ & $N{=}16$ & 0.411$^\\dagger$ & 0.281 \\\\\n\\quad FK & $N{=}8$  & 0.267 & 0.275 \\\\\n\\quad FK & $N{=}16$ & 0.283 & 0.279 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Across model families} (LLaMA CoNLL, $N{=}16$, 3 seeds)} \\\\\n\\quad SJ &  & $0.474{\\pm}0.009$ & --- \\\\\n\\quad FK &  & $0.467{\\pm}0.009$ & --- \\\\\n\\quad EM &  & $0.473{\\pm}0.010$ & --- \\\\\n\\quad VC &  & $0.470{\\pm}0.006$ & --- \\\\\n\\quad LP &  & $0.311{\\pm}0.003$ & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_temperature_robustness}\n\\caption{Temperature robustness on SciERC ($N{=}8$). Top: NER; bottom: RE. SJ maintains stable $\\rho$ across $T{=}0.7$ and $T{=}1.0$, while FK shows mixed sensitivity. LP shows the largest NER temperature effect ($\\Delta\\rho{=}{+}0.044$); RE $T{=}0.7$ LP data unavailable.}\n\\label{fig:temperature_robustness}\n\\end{figure}\n\n\\paragraph{Temperature sensitivity.}\nSJ NER $\\rho$ shifts from 0.364 ($T{=}0.7$) to 0.360 ($T{=}1.0$), a difference of 0.004.\nFK NER $\\rho$ drops by 0.022, while RE $\\rho$ increases by 0.091, likely reflecting reduced diversity at lower temperature interacting differently across tasks.\nLP exhibits the largest temperature effect on NER ($\\rho{=}0.249$ at $T{=}0.7$ vs.\\ $0.205$ at $T{=}1.0$, $\\Delta{=}{+}0.044$), consistent with lower temperature concentrating probability mass and improving LP's discriminative power for quality estimation; RE $T{=}0.7$ LP data is not available.\nAcross all comparisons, the signal hierarchy is preserved at both temperatures on NER (SJ${>}$FK${>}$LP at $T{=}0.7$: $0.364{>}0.289{>}0.249$; at $T{=}1.0$: $0.360{>}0.267{>}0.205$).\n\n\\paragraph{Sample size scaling.}\nIncreasing from $N{=}8$ to $N{=}16$ improves SJ on Qwen SciERC NER: $\\rho$ rises from 0.360 to $0.411{\\pm}0.010$ (three seeds: 0.398, 0.423, 0.410), a gain of $+0.047$.\nThe magnitude of $N$-scaling gains is setting-dependent (LLaMA SciERC NER yields $+0.016$ and Qwen CoNLL NER $+0.014$), though the direction is consistently positive.\nLLaMA CoNLL exhibits the most uniform scaling: all four consistency signals gain $\\Delta\\rho{\\approx}{+}0.042$ (range: $+0.039$ to $+0.044$) while LP gains only $+0.004$ (Table~\\ref{tab:quality_estimation}).\nFK $N$-scaling is seed-dependent: Qwen SciERC gains range from $+0.005$ to $+0.023$ across seeds (mean $+0.016$), while LLaMA CoNLL yields $+0.039$ (3-seed mean); individual seed FK shifts vary substantially under the unified pipeline, so this should not be interpreted as a robust trend.\nVC $N$-scaling is consistently positive ($+0.005$ on Qwen CoNLL, $+0.018$ on LLaMA SciERC, $+0.030$ on Qwen SciERC), while LP is approximately $N$-invariant ($\\Delta{\\leq}0.034$).\nSJ, EM, and VC scale consistently across all tested settings; only FK shows seed-dependent variation that does not constitute a reliable trend, structural and binary-agreement signals are the most robust to $N$.\nAt $N{=}16$, SJ converges to comparable NER performance with VC ($\\Delta{=}0.002$) while exhibiting lower cross-seed variance ($\\sigma{=}0.010$ vs.\\ $0.026$), a more stable alternative at higher sample sizes.\n\n\\paragraph{Transfer across model families.}\nLLaMA-3.1-8B-Instruct shows a similar SJ--FK ordering on SciERC NER (SJ $\\rho{=}0.325{\\pm}0.021$, FK $\\rho{=}0.256{\\pm}0.024$, $\\Delta\\rho{=}0.069$; permutation $p{=}0.06$, borderline).\nOn CoNLL, the gap across model families is minimal (Table~\\ref{tab:quality_estimation}): SJ achieves $\\rho{=}0.431$ (LLaMA) vs.\\ 0.436 (Qwen), $\\Delta{=}0.005$.\nAt $N{=}16$, the structural-over-LP advantage holds across all four tested NER settings: Qwen SciERC (VC $\\rho{=}0.409$ vs.\\ LP 0.239, $\\Delta{=}{+}0.170$), Qwen CoNLL (EM $\\rho{=}0.463$ vs.\\ LP 0.328, $\\Delta{=}{+}0.135$),\\footnote{Qwen CoNLL $N{=}16$ was not recomputed under the unified pipeline; LP $\\rho{=}0.328$ may differ slightly from the registry value (0.315) due to instance filtering.} LLaMA SciERC (VC $\\rho{=}0.452$ vs.\\ LP 0.277, $\\Delta{=}{+}0.175$), and LLaMA CoNLL 3-seed (SJ $\\rho{=}0.474{\\pm}0.009$ vs.\\ LP $0.311{\\pm}0.003$, $\\Delta{=}{+}0.163$).\n\n\\paragraph{FK independence: instance-level permutation test.}\\label{app:fk_independence}\n\nTo verify that Fleiss' $\\kappa$ reflects genuine within-instance agreement rather than marginal-rate artifacts, we conduct instance-level permutation tests across three configurations.\nFor each instance, we permute sample labels 10{,}000 times to generate a null distribution of FK under independence, then compare the observed FK against this null via a one-sample $t$-test and permutation $p$-value.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Instance-level FK independence test. Permutation tests confirm FK reflects true within-instance agreement (all $p{<}0.001$). Split-half reliability $r$ computed by randomly partitioning $N$ samples into two halves and correlating their FK scores.}\n\\label{tab:fk_independence}\n\\resizebox{\\columnwidth}{!}{\n\\begin{tabular}{lrcccc}\n\\toprule\nConfig & $n$ & FK mean & 95\\% CI & $t$ & Split-half $r$ \\\\\n\\midrule\nSciERC (Qwen) & 529 & 0.402 & [0.376, 0.428] & 30.8 & 0.395 \\\\\nCoNLL (LLaMA) & 2{,}756 & 0.927 & [0.919, 0.935] & 225.9 & 0.578 \\\\\nCoNLL (Qwen) & 2{,}756 & 0.720 & [0.706, 0.734] & 102.1 & 0.520 \\\\\n\\bottomrule\n\\end{tabular}\n}\n\\end{table}\n\nTable~\\ref{tab:fk_independence} reports the results.\nAll configurations reject the independence null at $p{<}0.001$ ($n{=}529$--$2{,}756$), FK captures genuine inter-sample agreement rather than chance label co-occurrence.\nSplit-half reliability ranges from $r{=}0.395$ (SciERC) to $r{=}0.578$ (CoNLL LLaMA), moderate stability: FK estimates from half the samples correlate positively with those from the other half, though the SciERC value suggests noisier estimation on harder tasks with fewer samples.\nThe higher FK means on CoNLL ($0.720$--$0.927$) vs.\\ SciERC ($0.402$) mirror the difficulty gradient observed in the main quality estimation results.\n\n\\section{Calibration Analysis}\\label{app:calibration}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_reliability}\n\\caption{Reliability diagrams on SciERC ($N{=}8$, $T{=}1.0$). Top: mean F1 vs.\\ binned confidence; bottom: instance counts per bin. Left: NER; right: RE. NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE shows greater miscalibration (ECE 0.109--0.339), RE calibration remains challenging for compound extraction tasks.}\n\\label{fig:reliability}\n\\end{figure*}\n\nReliability diagrams use 10 equal-width bins.\nNER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE exhibits greater miscalibration (ECE 0.109--0.339), translating consistency scores into calibrated confidence estimates is feasible for NER but remains challenging for compound extraction tasks.\n\n\\section{Additional Analyses}\\label{app:additional}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_signal_heatmap}\n\\caption{Quality estimation heatmap (Spearman $\\rho$) across five signals and four configurations. Left: full evaluation set; right: conditional set (non-zero F1 instances). On the full set, structural signals dominate on SciERC NER while all signals converge on CoNLL. On the conditional set, EM emerges as the strongest signal on both NER ($\\rho{=}0.360$) and RE ($\\rho{=}0.417$), while LP RE collapses to near-zero ($\\rho{=}0.011$).}\n\\label{fig:signal_heatmap}\n\\end{figure*}\n\n\\paragraph{Per-relation diagnostic.}\nRE signal degradation is relation-specific.\n\\textsc{Feature-Of} has near-zero correlation ($\\rho{=}0.004$), while \\textsc{Hyponym-Of} achieves $\\rho{=}0.646$.\nThe primary bottleneck is entity span errors, which account for 55.5\\% of RE false negatives. This is a prerequisite failure that consistency signals cannot detect, as they measure agreement among equally incorrect extractions.\nWe note that RE analysis relies on a single dataset (SciERC); generalization to other RE benchmarks remains to be validated.\n\n\\paragraph{Capability stratification.}\nFor NER, SJ effectiveness scales with structural complexity: on SciERC instances with 6+ entities, $\\rho{=}0.547$, compared to $\\rho{=}0.415$ for 1--2 entities.\nThe SJ advantage over LP remains stable across sentence-length quartiles ($\\Delta\\rho{\\approx}0.08$--$0.20$).\nFor RE, SJ $\\rho$ increases monotonically with sentence length (Q1: 0.110 $\\to$ Q4: 0.473; Fisher $z$-test $p{=}0.004$): longer, more relation-dense sentences provide richer structure for consistency-based estimation.\nBoth proxies are weakly correlated with F1 ($|r|{<}0.15$), they capture input complexity rather than directly predicting output quality; however, entity count and sentence length are themselves moderately correlated ($\\rho{=}0.650$), so they reflect overlapping rather than independent complexity dimensions.\nFor RE, entity count and relation count are strongly correlated ($\\rho{=}0.769$) and thus reflect a single structural complexity dimension rather than independent axes.\nOn the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\\rho{=}0.630$, LP $\\rho{=}0.554$, and SJ $\\rho{=}0.502$, all far above the full-set levels.\nRicher relational structure provides more signal for consistency-based estimation, complementing the task-level boundary established by WNUT-17: structural signals are most effective within a ``sweet spot'' of sufficient model capability and sufficient output complexity.\n\n\\paragraph{Length vs.\\ log-probability.}\nFigure~\\ref{fig:length_logprob_scatter} shows that mean log-probability is weakly positively correlated with output length (NER: $\\rho{=}0.386$, $n{=}4{,}232$; RE: $\\rho{=}0.326$, $n{=}3{,}176$), ruling out length-penalty confounding as an explanation for LP's selection failure: longer outputs receive \\textit{higher}, not lower, token-averaged log-probability under constrained decoding.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_length_logprob_scatter}\n\\caption{Output length vs.\\ mean log-probability on SciERC ($N{=}8$, $T{=}1.0$). Positive correlations (NER: $\\rho{=}0.386$; RE: $\\rho{=}0.326$) rule out length-penalty confounding.}\n\\label{fig:length_logprob_scatter}\n\\end{figure}\n\n\\paragraph{Evaluation circularity and LOO-SJ equivalence.}\nConsensus-proximity selection chooses $\\hat{y} = \\arg\\max_{y_i} \\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$.\nLeave-one-out SJ (LOO-SJ) for sample $y_i$ is $\\text{LOO-SJ}_i = \\frac{1}{N-1}\\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$.\nSince the $\\frac{1}{N-1}$ constant is shared across all candidates within an instance, $\\arg\\max_{y_i} \\text{LOO-SJ}_i = \\arg\\max_{y_i} \\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$; the two selection rules are equivalent.\nStandard (non-LOO) SJ adds the self-comparison term $\\text{SJ}(y_i, y_i) = 1$ to each candidate, which is constant and thus does not affect ranking.\nEmpirically, LOO-SJ yields $\\Delta\\rho{=}{-}0.014$ relative to standard SJ (a correlation-level difference), with a maximum per-instance score difference of $3.1{\\times}10^{-4}$ (negligible at the individual prediction level).\nEvaluation circularity is negligible.\n\n\\paragraph{SJ normalizer robustness.}\nEquation~\\ref{eq:sj} uses $\\max(|g_i|, |g_j|)$ as the denominator; an alternative is the union size $|g_i \\cup g_j|$.\nTable~\\ref{tab:sj_normalizer} compares the two normalizers across all six model--dataset combinations ($N{=}8$, $T{=}1.0$, seed${=}42$): $|\\Delta\\rho|{<}0.01$ in every case, the choice between max and union normalization does not affect conclusions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{SJ normalizer comparison (Spearman $\\rho$; $N{=}8$, $T{=}1.0$, seed${=}42$). Max: $\\max(|g_i|,|g_j|)$; Union: $|g_i \\cup g_j|$.}\n\\label{tab:sj_normalizer}\n\\begin{tabular}{@{}ll ccc@{}}\n\\toprule\nDataset & Model & $\\rho$(max) & $\\rho$(union) & $\\Delta\\rho$ \\\\\n\\midrule\nCoNLL & Qwen3-8B & .436 & .438 & $-$.002 \\\\\nCoNLL & Qwen3-4B & .422 & .421 & $+$.000 \\\\\nCoNLL & LLaMA-8B & .431 & .432 & $-$.000 \\\\\nSciERC & Qwen3-8B & .360 & .365 & $-$.005 \\\\\nSciERC & Qwen3-4B & .422 & .423 & $-$.001 \\\\\nSciERC & LLaMA-8B & .363 & .372 & $-$.009 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Conditional filtering details.}\nOn LLaMA conditional RE (non-zero F1 instances), SJ recovers to $\\rho{=}0.405$ while FK drops to $\\rho{=}0.259$, consistent with the NER structural advantage; on full-set RE, however, the SJ--FK difference is non-significant ($\\Delta\\rho{=}{-}0.005$, $p{=}0.53$; preliminary).\nAt $N{=}16$, the divergence persists: SJ maintains $\\rho{=}0.308$ on conditional RE while LP drops to $\\rho{=}{-}0.026$.\nEM ranks first across all four tested conditional configurations: SciERC NER ($\\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\\rho{=}0.466$), CoNLL LLaMA 3-seed ($\\rho{=}0.462$), and SciERC RE ($\\rho{=}0.417$). This holds despite full-set rankings ranging from \\#1 (CoNLL Qwen) to \\#5 (SciERC RE).\nOn the full set, EM is diluted by trivial agreement: instances where all $N$ samples produce identical (possibly incorrect) outputs receive EM${=}1$ regardless of quality, compressing the signal's dynamic range.\nOn the conditional set, where the model demonstrably produces varied outputs, exact agreement becomes the strongest quality signal.\nThe margin over SJ is largest on RE ($\\Delta\\rho{=}{+}0.171$), where compound extraction decisions amplify output variability, and smallest on CoNLL LLaMA ($\\Delta\\rho{=}{+}0.002$), where all signals converge near $\\rho{\\approx}0.46$.\n\n\\paragraph{WNUT-17 full signal analysis.}\nTable~\\ref{tab:wnut} reports all five signals on WNUT-17 with full-set and conditional $\\rho$.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Quality estimation on WNUT-17 (Qwen, $N{=}16$, $T{=}1.0$, $n{=}689$). Cond: non-zero F1 instances ($n{=}334$). Full-set $\\rho$ reflects binary success prediction; conditional $\\rho$ measures quality gradation. LP's conditional $\\rho$ is highest despite negative full-set $\\rho$.}\n\\label{tab:wnut}\n\\begin{tabular}{lcccc}\n\\toprule\nSignal & $\\rho$ & AUROC & Cond.\\ $\\rho$ & Cond.\\ $p$ \\\\\n\\midrule\nVC      & .724 & .913 & .038 & .487 \\\\\nFK      & .125 & .555 & .169 & .002 \\\\\nSJ      & .089 & .517 & .288 & ${<}$1e-7 \\\\\nEM      & .050 & .487 & .333 & ${<}$1e-9 \\\\\nLP & $-$.410 & .219 & .350 & ${<}$1e-10 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\nThe full-set $p$-values are: VC ${<}$1e-112, FK $p{=}0.001$, SJ $p{=}0.020$, EM $p{=}0.194$, LP ${<}$1e-28.\nVC's high full-set $\\rho{=}0.724$ is entirely driven by the zero/non-zero boundary (conditional $\\rho{=}0.038$, $p{=}0.49$), while LP's conditional $\\rho{=}0.350$ is the highest among all signals on the non-zero subset, full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.\n\n\\paragraph{Cross-configuration selection analysis.}\nTable~\\ref{tab:cross_selection} extends the selection analysis to five additional configurations.\nOn LLaMA SciERC, where output diversity remains substantial (18\\% identical outputs, 39\\% unique), LP achieves the highest selection F1 (0.652) at $N{=}8$ but still falls within bootstrap noise of single-sample (0.646), replicating the gap observed on Qwen SciERC (Table~\\ref{tab:selection}).\nOn LLaMA FewNERD ($n{=}32{,}565$, 3-seed mean), LP is the only signal with positive selection ($+0.36$~pp), confirming LP as the most robust selection signal across model families (Qwen FewNERD: $+1.39$~pp, Table~\\ref{tab:fewnerd}). All structural signals degrade selection (VC $-2.39$~pp, SJ $-0.52$~pp), consistent with the Qwen pattern. LLaMA FewNERD degeneracy ($23.4{\\pm}4.7$\\%, 3 seeds) is higher than Qwen ($13.0$\\%), illustrating the capability-diversity tension: LLaMA achieves stronger greedy F1 ($0.784$ vs.\\ $0.748$, $+3.6$~pp) but at the cost of higher degeneracy ($+10.4$~pp) and reduced oracle headroom ($10.0$ vs.\\ $12.4$~pp).\nOn CoNLL, 48--87\\% of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect (single-sample F1 ${\\approx}$0.91--0.92) rather than signal failure, and selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{Best-of-$N$ selection F1 (macro, instance-averaged) across configurations ($T{=}1.0$, 3-seed mean). Best non-oracle signal per row in \\textbf{bold}. LP is the only signal with positive selection on both FewNERD configurations (Qwen $+1.39$~pp, Table~\\ref{tab:fewnerd}; LLaMA $+0.36$~pp). At $N{=}16$ on LLaMA CoNLL, VC achieves small but significant gains ($+0.28$~pp, $p{<}0.03$; see text below). CoNLL shows especially tight clustering where greedy already exceeds 0.90.}\n\\label{tab:cross_selection}\n\\begin{tabular}{llccccccc}\n\\toprule\nConfig & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\\\\n\\midrule\nLLaMA/SciERC $N{=}8$ & 529 & .646 & .778 & .643 & .639 & .634 & \\textbf{.652} & .633 \\\\\nLLaMA/SciERC $N{=}16$ & 529 & .645 & .806 & \\textbf{.649} & \\textbf{.649} & .640 & .646 & .640 \\\\\n\\addlinespace\nLLaMA/FewNERD $N{=}8$ & 32{,}565 & .784 & .884 & .779 & .779 & .774 & \\textbf{.788} & .760 \\\\\n\\addlinespace\nQwen/CoNLL $N{=}8$ & 2{,}756 & .908 & .948 & \\textbf{.899} & .893 & .898 & .897 & .895 \\\\\nLLaMA/CoNLL $N{=}8$ & 2{,}756 & .924 & .943 & .924 & \\textbf{.925} & .924 & .924 & .923 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\paragraph{Diminishing returns of $N$-scaling.}\nOur $N{=}8$ and $N{=}16$ comparisons (Table~\\ref{tab:robustness}) characterize the marginal value of additional samples for test-time scaling \\cite{brown2024monkeys, snell2025scaling}.\nFor quality estimation, structural signals benefit consistently but sublinearly: SJ $\\rho$ improves by $+0.047$ (Qwen SciERC, 3-seed mean) and $+0.032$ (LLaMA CoNLL, 3-seed mean) when doubling from $N{=}8$ to $N{=}16$, while log-probability is approximately $N$-invariant ($\\Delta\\rho{\\leq}0.021$).\nStructural signals use $\\binom{N}{2}$ pairwise comparisons (28 pairs at $N{=}8$, 120 at $N{=}16$), but the $\\rho$ improvement is far less than proportional, each additional comparison yields diminishing information.\nThis asymmetry gives structural signals a relative advantage in the compute-constrained regime: at $N{=}8$, SJ already achieves $\\rho{=}0.431$ on LLaMA CoNLL (vs.\\ LP $\\rho{=}0.307$, $\\Delta{=}{+}0.124$), and the gap \\textit{widens} at $N{=}16$ ($\\Delta{=}{+}0.163$) because structural signals continue to benefit from additional pairwise evidence while LP does not.\nFor sample selection, additional samples increase the oracle upper bound (more draws raise the probability of a high-quality candidate), but signal-based selection remains flat because the selector's inability to identify the best candidate is a granularity limitation, not a sample size limitation.\nThe practical implication is that $N{=}8$ captures most of the achievable quality estimation benefit; further scaling widens rather than closes the correlation-selection gap absent stronger per-sample selectors.\n\n\\paragraph{$N{=}16$ CoNLL selection: small but significant.}\nWhile quality estimation benefits sublinearly from $N$-scaling, selection behavior at $N{=}16$ reveals a nuanced exception on LLaMA CoNLL.\nVC achieves the largest gain over single-sample ($+0.28$~pp, $p{=}0.003$--$0.027$ across 3 seeds, all significant), with SJ, FK, and EM at $+0.22$--$0.23$~pp and LP at $+0.12$~pp (2/3 seeds significant).\nThese gains are statistically significant but practically minimal: oracle headroom at $N{=}16$ is only 2.5~pp, so VC captures approximately 10\\% of the available headroom.\nThis reinforces the primary finding: even under the most favorable conditions (high baseline performance, more candidates, and aggregated multi-seed evidence), signal-based selection recovers only a fraction of the oracle headroom available.\n\n\\section{Bootstrap CI for Signal Comparisons}\\label{app:bootstrap_signal}\n\nTable~\\ref{tab:bootstrap_signal_ci} reports bootstrap confidence intervals for individual signal $\\rho$ and pairwise $\\Delta\\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$).\nThe SJ--LP gap ($\\Delta\\rho{=}{+}0.155$) is clearly significant, the structural advantage reported in \\S\\ref{sec:qe_results} is robust.\nThe VC--SJ gap ($\\Delta\\rho{=}{+}0.019$) is not significant; these two structural signals perform comparably.\nThe SJ--EM gap ($\\Delta\\rho{=}{+}0.065$) is borderline significant, with the CI lower bound at $+0.003$ and upper bound at $+0.130$.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Bootstrap 95\\% CIs for signal $\\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$). Top: individual signals. Bottom: pairwise $\\Delta\\rho$; ``Sig.'' indicates whether the 95\\% CI excludes zero.}\n\\label{tab:bootstrap_signal_ci}\n\\begin{tabular}{lcc}\n\\toprule\nSignal & $\\rho$ & 95\\% CI \\\\\n\\midrule\nVC & +0.379 & [+0.299, +0.456] \\\\\nSJ & +0.360 & [+0.277, +0.437] \\\\\nEM & +0.295 & [+0.212, +0.371] \\\\\nFK & +0.267 & [+0.176, +0.354] \\\\\nLP & +0.205 & [+0.119, +0.291] \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{0.5em}\n\n\\begin{tabular}{lccc}\n\\toprule\nComparison & $\\Delta\\rho$ & 95\\% CI & Sig. \\\\\n\\midrule\nSJ $-$ LP & +0.155 & [+0.074, +0.234] & Yes \\\\",
      "numLines": 300,
      "startLine": 1,
      "totalLines": 2283
    }
  }
}
```

</details>

---

### Assistant

_source line 47_

<details><summary>Logged reasoning block</summary>

```text
Now I have a comprehensive picture. Let me compile the findings.

From the paper's Table~\ref{tab:robustness} (appendix.tex line 34-65):

**LLaMA CoNLL, N=16, 3-seed mean:**
- SJ: 0.474 ± 0.009
- EM: 0.473 ± 0.010
- VC: 0.470 ± 0.006
- FK: 0.467 ± 0.009


- LP: 0.311 ± 0.003

Looking at the individual seed results from unified_rho_full.json for LLaMA CoNLL N=16, I can see the variation across runs—SJ consistently performs strongest, ranging from 0.4662 to 0.4836 across the three seeds, while the other methods cluster around 0.46-0.47. The peak performance is SJ at 0.4836 from seed42.

Comparing this to the primary table results at N=8 with seed=42, the numbers are notably lower—EM CoNLL (Qwen) tops out at 0.451, with SJ and LLaMA variants in the 0.43 range. When I look at the N=16 appendix values, LLaMA CoNLL SJ averages 0.474 across seeds, Qwen EM reaches 0.463, and LLaMA SciERC VC hits 0.452. The WNUT-17 VC result of 0.724 is an outlier driven by the zero/non-zero boundary effect.

Looking at the stratified subsets, SJ on high-entity SciERC instances climbs to 0.547, and RE Q4 SJ reaches 0.473. So the peak "standard" correlation is around 0.484 for LLaMA CoNLL SJ at N=16, with the main table capped at 0.451, which aligns with the abstract's claim of "ρ up to 0.45."

The reviewer's concern about EM 0.472 on LLaMA CoNLL likely points to the N=16 3-seed mean of 0.473 from the robustness analysis. The question becomes whether the abstract should be updated to reflect these higher values, since the paper does report correlations reaching 0.474 and even 0.547 in stratified subsets, which exceed the stated 0.45 threshold. The stratified results push even higher at 0.547 for cases with 6+ entities. So the abstract's claim of "ρ up to 0.45" is actually understating what the paper reports—the N=16 robustness table shows a 3-seed mean of 0.474, and individual seeds reach 0.484, which is notably higher than the primary N=8 result of 0.451.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "f1844e81-d351-43c1-b50e-3e199d5b4cc1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0156WRSLZuCDUNGxXxMTZwBZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13685,
      "cache_read_input_tokens": 52358,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13685
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

_source line 48_

Now I have the full picture. Here's the analysis:

---

## Abstract ρ_max 核实结果

### 当前 Abstract 写法
> Quality estimation signals correlate with oracle F1 ($\rho$ up to 0.45, AUROC up to 0.82)

### 实际 ρ 值汇总

**Table 1 (N=8, seed=42, primary)**

| Config | Signal | ρ |
|--------|--------|---|
| CoNLL (Qwen) | EM | **0.451** ← Table 1 最高 |
| CoNLL (Qwen) | SJ | 0.436 |
| CoNLL (LLaMA) | SJ/EM | 0.431 |

→ 0.451 四舍五入 = 0.45，Abstract 对 N=8 primary 是准确的。

**Table robustness (N=16, LLaMA CoNLL, 3-seed mean ± σ)**

| Signal | ρ |
|--------|---|
| SJ | **0.474 ± 0.009** |
| EM | **0.473 ± 0.010** |
| VC | 0.470 ± 0.006 |
| FK | 0.467 ± 0.009 |

**Individual seed 最高值 (unified_rho_full.json, N=16)**

| Config | Signal | ρ |
|--------|--------|---|
| LLaMA CoNLL seed42 | SJ | **0.4836** ← 全局最高 |
| LLaMA CoNLL seed42 | EM | 0.4818 |
| LLaMA CoNLL seed456 | EM | 0.4752 |

**特殊情况（不宜放 Abstract）**
- WNUT-17 VC full-set: ρ=0.724（但 conditional ρ=0.038，被 zero/non-zero boundary 驱动）
- SciERC 6+ entities 子集: SJ ρ=0.547（stratified subset）

### 结论

| 范围 | ρ_max | Abstract "0.45" 是否准确 |
|------|-------|--------------------------|
| N=8 primary (Table 1) | 0.451 | ✅ 准确 |
| N=16 3-seed mean (Tab robustness) | **0.474** | ❌ 偏低 |
| N=16 单 seed 最高 | **0.484** | ❌ 偏低 |

审稿人提到的 "EM 0.472 (LLaMA CoNLL)" 应该指的是 Tab robustness 中 EM 3-seed mean = 0.473。

### 修正建议

**方案 A**（保守，限定 N=8）: 不改，但需在 Abstract 中明确 "at N=8"，避免被认为隐瞒 N=16 结果。

**方案 B**（推荐）: 改为 `$\rho$ up to 0.47`，覆盖 N=16 三种子均值 0.474，四舍五入准确。Abstract 不需要区分 N=8/N=16，"up to" 应覆盖论文中所有正式报告的值。

**方案 C**（最精确）: 改为 `$\rho$ up to 0.48`，覆盖单 seed 最高值 0.484，但论文正文表格报的是 3-seed mean 0.474，用 0.48 可能反而过高。

推荐 **方案 B: "ρ up to 0.47"**。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "uuid": "4cb10be5-b53d-45fb-be4e-a36317eb2a28",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0156WRSLZuCDUNGxXxMTZwBZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13685,
      "cache_read_input_tokens": 52358,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13685
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

_source line 49_

Now I have the full picture. Here's the analysis:

---

## Abstract ρ_max 核实结果

### 当前 Abstract 写法
> Quality estimation signals correlate with oracle F1 ($\rho$ up to 0.45, AUROC up to 0.82)

### 实际 ρ 值汇总

**Table 1 (N=8, seed=42, primary)**

| Config | Signal | ρ |
|--------|--------|---|
| CoNLL (Qwen) | EM | **0.451** ← Table 1 最高 |
| CoNLL (Qwen) | SJ | 0.436 |
| CoNLL (LLaMA) | SJ/EM | 0.431 |

→ 0.451 四舍五入 = 0.45，Abstract 对 N=8 primary 是准确的。

**Table robustness (N=16, LLaMA CoNLL, 3-seed mean ± σ)**

| Signal | ρ |
|--------|---|
| SJ | **0.474 ± 0.009** |
| EM | **0.473 ± 0.010** |
| VC | 0.470 ± 0.006 |
| FK | 0.467 ± 0.009 |

**Individual seed 最高值 (unified_rho_full.json, N=16)**

| Config | Signal | ρ |
|--------|--------|---|
| LLaMA CoNLL seed42 | SJ | **0.4836** ← 全局最高 |
| LLaMA CoNLL seed42 | EM | 0.4818 |
| LLaMA CoNLL seed456 | EM | 0.4752 |

**特殊情况（不宜放 Abstract）**
- WNUT-17 VC full-set: ρ=0.724（但 conditional ρ=0.038，被 zero/non-zero boundary 驱动）
- SciERC 6+ entities 子集: SJ ρ=0.547（stratified subset）

### 结论

| 范围 | ρ_max | Abstract "0.45" 是否准确 |
|------|-------|--------------------------|
| N=8 primary (Table 1) | 0.451 | ✅ 准确 |
| N=16 3-seed mean (Tab robustness) | **0.474** | ❌ 偏低 |
| N=16 单 seed 最高 | **0.484** | ❌ 偏低 |

审稿人提到的 "EM 0.472 (LLaMA CoNLL)" 应该指的是 Tab robustness 中 EM 3-seed mean = 0.473。

### 修正建议

**方案 A**（保守，限定 N=8）: 不改，但需在 Abstract 中明确 "at N=8"，避免被认为隐瞒 N=16 结果。

**方案 B**（推荐）: 改为 `$\rho$ up to 0.47`，覆盖 N=16 三种子均值 0.474，四舍五入准确。Abstract 不需要区分 N=8/N=16，"up to" 应覆盖论文中所有正式报告的值。

**方案 C**（最精确）: 改为 `$\rho$ up to 0.48`，覆盖单 seed 最高值 0.484，但论文正文表格报的是 3-seed mean 0.474，用 0.48 可能反而过高。

推荐 **方案 B: "ρ up to 0.47"**。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 129207,
  "duration_api_ms": 130065,
  "num_turns": 18,
  "stop_reason": "end_turn",
  "session_id": "ae3cc154-f589-46df-b165-661b1879021e",
  "total_cost_usd": 0.612702,
  "usage": {
    "input_tokens": 10,
    "cache_creation_input_tokens": 54202,
    "cache_read_input_tokens": 188777,
    "output_tokens": 7126,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 54202,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 2478,
        "cache_read_input_tokens": 52358,
        "cache_creation_input_tokens": 13685,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 13685
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1266,
      "outputTokens": 17,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.001351,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 10,
      "outputTokens": 7126,
      "cacheReadInputTokens": 188777,
      "cacheCreationInputTokens": 54202,
      "webSearchRequests": 0,
      "costUSD": 0.611351,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "081215a3-b52f-4d80-aad3-41492abe0707"
}
```

</details>

---
