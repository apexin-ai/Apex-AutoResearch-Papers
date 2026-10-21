# audit final maintext tables — Part 1 of 2

**Trace Verbosity Degrades SFT Verdict Prediction: A Case Study in Information Density Effects** · Worker execution logs

[Transcript overview](../audit-final-maintext-tables.md) · [Part 2 →](part-002.md) · [Structured JSON](../../../sessions/ab/ab4d42cdec4512883914.json)

## Before a recorded user message

## Before a recorded user message

32 recorded events


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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
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
    "mcp__agent-ml-research__read_registry",
    "mcp__agent-ml-research__register_artifact",
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
  "uuid": "cbad021a-41db-483a-baf3-47e7c2f5122e",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/memory/"
  },
  "fast_mode_state": "off"
}
```

---


### Assistant

_source line 3_

<details><summary>Logged reasoning block</summary>

```text
The user wants a comprehensive data audit of their paper before submission. Let me start by reading all the .tex files and the registry data in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "15c649d6-f4fd-4ef4-9e03-27e0e797b995",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SBxbmgvmsqSc9yCS4QexJF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12724,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12724
      },
      "output_tokens": 20,
      "service_tier": "standard",
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

_source line 4_

开始全面数据审计。先并行读取所有 .tex 文件和 registry 数据。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "b4965984-0d8b-498c-bafa-b3f1b2cb011e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SBxbmgvmsqSc9yCS4QexJF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12724,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12724
      },
      "output_tokens": 20,
      "service_tier": "standard",
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

_source line 5_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed",
    "resetsAt": 1779581400,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "3ac5cbcd-1780-4236-98f8-dfdb4cc71ba5",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 6_

<details open><summary>🔧 Tool call — Glob · `toolu_01AM4yxtr8CvPpLwpZa8YWTa`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "b6be3deb-deb5-4c14-a371-ba6827f2ba5e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SBxbmgvmsqSc9yCS4QexJF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12724,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12724
      },
      "output_tokens": 20,
      "service_tier": "standard",
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

_source line 7 · 2026-05-23T19:17:08.557Z_

<details><summary>↩ Tool result · reported error · `toolu_01AM4yxtr8CvPpLwpZa8YWTa`</summary>

```text
&lt;tool_use_error>Directory does not exist: /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/paper. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study.&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "5a70d5a7-fc8c-4dfe-83d5-f0e4b578d1de",
  "tool_use_result": "Error: Directory does not exist: /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/paper. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study."
}
```

</details>

---


### Tool call

_source line 8_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_013c6QPgY9XGzAy7Vu3wft26`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry",
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
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "4453247f-06c2-43b8-8fcd-053df4c8a6f5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01SBxbmgvmsqSc9yCS4QexJF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12724,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12724
      },
      "output_tokens": 20,
      "service_tier": "standard",
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

_source line 9 · 2026-05-23T19:17:09.091Z_

<details><summary>↩ Tool result · `toolu_013c6QPgY9XGzAy7Vu3wft26`</summary>

````text
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
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "e7d00f76-48df-44c8-8003-42aa9890e374",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_registry"
    ],
    "query": "select:mcp__agent-ml-research__read_registry",
    "total_deferred_tools": 22
  }
}
```

</details>

---


### Assistant

_source line 10_

<details><summary>Logged reasoning block</summary>

```text
The paper directory doesn't exist at the local path. Let me check where the .tex files actually are locally, and also fetch the registry data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "972a215d-7a0a-475f-ae6b-bae8fd9269b3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DYcCGyc1TgztKPdVJDQxML",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 728,
      "cache_read_input_tokens": 24565,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 728
      },
      "output_tokens": 23,
      "service_tier": "standard",
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

<details open><summary>🔧 Tool call — Glob · `toolu_01Gd5a4bsNXetgVc51847vNf`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "97dd7587-91f8-4609-a2cf-0219db68c934",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DYcCGyc1TgztKPdVJDQxML",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 728,
      "cache_read_input_tokens": 24565,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 728
      },
      "output_tokens": 23,
      "service_tier": "standard",
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

_source line 12 · 2026-05-23T19:17:13.137Z_

<details><summary>↩ Tool result · `toolu_01Gd5a4bsNXetgVc51847vNf`</summary>

```text
artifacts/dream_reports/dream_20260515T013018/best/paper.tex
artifacts/dream_reports/dream_20260515T013018/median/paper.tex
artifacts/dream_reports/dream_20260515T013018/worst/paper.tex
artifacts/dream_reports/dream_20260515T084908/best/paper.tex
artifacts/dream_reports/dream_20260515T084908/median/paper.tex
artifacts/dream_reports/dream_20260515T084908/worst/paper.tex
artifacts/per_class_breakdown.tex
artifacts/_project/paper/section3_experimental_setup_d4f1e8.tex
artifacts/_project/paper/section3_experimental_setup.tex
artifacts/_project/paper/ethics_statement.tex
artifacts/_project/paper/ethics_statement_77cf5f.tex
artifacts/_project/paper/main_results_tables.tex
artifacts/_project/paper/main_results_tables_d8c8b6.tex
artifacts/paper_tables/main_results_tables.tex
artifacts/dream_reports/dream_20260516T105259/best/paper.tex
artifacts/dream_reports/dream_20260516T105259/median/paper.tex
artifacts/dream_reports/dream_20260516T105259/worst/paper.tex
artifacts/dream_reports/dream_20260516T155731/best/paper.tex
artifacts/dream_reports/dream_20260516T155731/median/paper.tex
artifacts/dream_reports/dream_20260516T155731/worst/paper.tex
artifacts/dream_reports/dream_20260518T113804/best/paper.tex
artifacts/dream_reports/dream_20260518T113804/median/paper.tex
artifacts/dream_reports/dream_20260518T113804/worst/paper.tex
artifacts/dream_reports/dream_20260518T125926/best/paper.tex
artifacts/dream_reports/dream_20260518T125926/median/paper.tex
artifacts/dream_reports/dream_20260518T125926/worst/paper.tex
artifacts/_project/paper/main.tex
artifacts/_project/paper/introduction.tex
artifacts/_project/paper/method.tex
artifacts/_project/paper/discussion.tex
artifacts/_project/paper/conclusion.tex
artifacts/_project/paper/appendix.tex
artifacts/_project/paper/arr_checklist.tex
artifacts/_project/paper/experiments.tex
artifacts/_project/paper/related_work.tex
artifacts/discussion.tex
artifacts/main.tex
artifacts/related_work.tex
docs/paper/arr_checklist.tex
docs/paper/introduction.tex
docs/paper/conclusion.tex
docs/paper/method.tex
docs/paper/related_work.tex
docs/paper/discussion.tex
docs/paper/experiments.tex
docs/paper/main.tex
docs/paper/appendix.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "a090aa7c-4a7f-400e-861c-b776283c5936",
  "tool_use_result": {
    "filenames": [
      "artifacts/dream_reports/dream_20260515T013018/best/paper.tex",
      "artifacts/dream_reports/dream_20260515T013018/median/paper.tex",
      "artifacts/dream_reports/dream_20260515T013018/worst/paper.tex",
      "artifacts/dream_reports/dream_20260515T084908/best/paper.tex",
      "artifacts/dream_reports/dream_20260515T084908/median/paper.tex",
      "artifacts/dream_reports/dream_20260515T084908/worst/paper.tex",
      "artifacts/per_class_breakdown.tex",
      "artifacts/_project/paper/section3_experimental_setup_d4f1e8.tex",
      "artifacts/_project/paper/section3_experimental_setup.tex",
      "artifacts/_project/paper/ethics_statement.tex",
      "artifacts/_project/paper/ethics_statement_77cf5f.tex",
      "artifacts/_project/paper/main_results_tables.tex",
      "artifacts/_project/paper/main_results_tables_d8c8b6.tex",
      "artifacts/paper_tables/main_results_tables.tex",
      "artifacts/dream_reports/dream_20260516T105259/best/paper.tex",
      "artifacts/dream_reports/dream_20260516T105259/median/paper.tex",
      "artifacts/dream_reports/dream_20260516T105259/worst/paper.tex",
      "artifacts/dream_reports/dream_20260516T155731/best/paper.tex",
      "artifacts/dream_reports/dream_20260516T155731/median/paper.tex",
      "artifacts/dream_reports/dream_20260516T155731/worst/paper.tex",
      "artifacts/dream_reports/dream_20260518T113804/best/paper.tex",
      "artifacts/dream_reports/dream_20260518T113804/median/paper.tex",
      "artifacts/dream_reports/dream_20260518T113804/worst/paper.tex",
      "artifacts/dream_reports/dream_20260518T125926/best/paper.tex",
      "artifacts/dream_reports/dream_20260518T125926/median/paper.tex",
      "artifacts/dream_reports/dream_20260518T125926/worst/paper.tex",
      "artifacts/_project/paper/main.tex",
      "artifacts/_project/paper/introduction.tex",
      "artifacts/_project/paper/method.tex",
      "artifacts/_project/paper/discussion.tex",
      "artifacts/_project/paper/conclusion.tex",
      "artifacts/_project/paper/appendix.tex",
      "artifacts/_project/paper/arr_checklist.tex",
      "artifacts/_project/paper/experiments.tex",
      "artifacts/_project/paper/related_work.tex",
      "artifacts/discussion.tex",
      "artifacts/main.tex",
      "artifacts/related_work.tex",
      "docs/paper/arr_checklist.tex",
      "docs/paper/introduction.tex",
      "docs/paper/conclusion.tex",
      "docs/paper/method.tex",
      "docs/paper/related_work.tex",
      "docs/paper/discussion.tex",
      "docs/paper/experiments.tex",
      "docs/paper/main.tex",
      "docs/paper/appendix.tex"
    ],
    "durationMs": 13,
    "numFiles": 47,
    "truncated": false
  }
}
```

</details>

---


### Tool call

_source line 13_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01LLuns1zDSsB4jqf2c3XUCk`</summary>

```json
{
  "project": "trace-verdict-study",
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
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "47ec2df9-b3ec-475c-a4de-c107618a8bf1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DYcCGyc1TgztKPdVJDQxML",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 728,
      "cache_read_input_tokens": 24565,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 728
      },
      "output_tokens": 23,
      "service_tier": "standard",
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

_source line 14 · 2026-05-23T19:17:14.809Z_

<details><summary>↩ Tool result · `toolu_01LLuns1zDSsB4jqf2c3XUCk`</summary>

```text
Error: result (351,844 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "00b8d484-dfd8-47e9-8a30-1a6a439f8394",
  "tool_use_result": {
    "content": "Error: result (351,844 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"deepseek_gradient_masking_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T09:51:05.056Z\", \"updated_at\": \"2026-05-23T13:45:23.758Z\", \"hypothesis\": \"DeepSeek-6.7B gradient masking multi-seed validation (seed 123): 99.8% gradient masking should achieve ≥98.5% accuracy, confirming dilution bound stability. Derived from deepseek_gradient_masking_seed42 (99.33%, dilution 0.06%).\", \"parent\": \"deepseek_gradient_masking_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --model_path deepseek-coder-6.7b-instruct --gradient_mask_ratio 0.998 --gradient_checkpointing --seed 123\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"874893\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_gradient_masking_seed123.log\", \"data_path\": \"/root/trace-verdict-study/data/exception_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 123, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/exception_only_test.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_gradient_masking_seed123/final/\"}, \"metrics\": {\"accuracy\": 0.9395, \"pass_precision\": 0.924, \"pass_recall\": 0.998, \"pass_f1\": 0.959, \"fail_precision\": 0.993, \"fail_recall\": 0.794, \"fail_f1\": 0.882}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-23T13:45:23.758Z\"}, \"codellama_gradient_masking_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T08:52:00.476Z\", \"updated_at\": \"2026-05-23T11:40:38.570Z\", \"hypothesis\": \"Cross-architecture gradient masking validation: CodeLlama-13B exception_only with 99.8% gradient masking should achieve ≥98.5% accuracy (vs baseline 99.89%±0.10), extending ≤4% dilution bound to third architecture family (Qwen + DeepSeek + CodeLlama)\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama_gradient_masking_seed42/final\", \"log_path\": \"~/runs/trace-verdict-study/codellama_gradient_masking_seed42.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-23T11:30:59.992Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-23T11:31:06.685621+00:00\"}]}, \"metrics\": {\"accuracy\": 1, \"accuracy_ci_lower\": 1, \"accuracy_ci_upper\": 1, \"eval_loss\": 0.0625, \"dilution_pct\": -0.11, \"pass_f1\": 1, \"fail_f1\": 1, \"n_test\": 1190, \"train_loss\": 2.2387, \"baseline_accuracy\": 99.89}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-23T11:40:38.570Z\"}, \"deepseek_gradient_masking_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T07:55:20.075Z\", \"updated_at\": \"2026-05-23T09:47:51.342Z\", \"hypothesis\": \"Cross-architecture gradient masking validation: DeepSeek-6.7B exception_only with 99.8% gradient masking should achieve ≥98.5% accuracy (vs baseline 99.39%), confirming that content quality (not gradient dilution) explains full_trace degradation across architectures, extending the ≤4% dilution bound beyond Qwen-7B\", \"spec\": {\"command\": \"bash -c \\\"... python train/train_sft.py --condition exception_only --model_path deepseek-coder-6.7b-instruct --gradient_mask_ratio 0.998 --gradient_checkpointing --seed 42\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"867878\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_gradient_masking_seed42.log\", \"submitted_at\": \"2026-05-23T07:56:01.348Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_test.jsonl\", \"wall_clock_seconds\": 6710.0, \"gpu_hours\": 1.86}, \"reproduce\": {\"finished_at\": \"2026-05-23T09:40:03.301Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-23T09:40:08.515903+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9933, \"accuracy_ci_lower\": 0.9882, \"accuracy_ci_upper\": 0.9975, \"pass_precision\": 1, \"pass_recall\": 0.9906, \"pass_f1\": 0.9953, \"fail_precision\": 0.9769, \"fail_recall\": 1, \"fail_f1\": 0.9883, \"eval_loss\": 0.0529, \"train_loss\": 0.9961, \"majority_baseline\": 0.715, \"lift\": 0.278}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_gradient_masking_seed42/final\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_gradient_masking_seed42.log\", \"completed_at\": \"2026-05-23T09:47:51.342Z\"}, \"full_trace_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T02:00:53.774Z\", \"updated_at\": \"2026-05-23T06:04:23.676Z\", \"hypothesis\": \"Full-trace multi-seed robustness (seed 456): full execution trace with chat-template-aware truncation achieves similar accuracy to seed42 (81.76%) and seed123, completing 3-seed statistics for the full_trace condition as rebuttal evidence\", \"parent\": \"full_trace_seed42_v5\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --gpu 0 --gradient_checkpointing --seed 456\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"854746\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_seed456.log\", \"submitted_at\": \"2026-05-23T03:42:11.640Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_test.jsonl\", \"wall_clock_seconds\": 8532.0, \"gpu_hours\": 2.37}, \"reproduce\": {\"finished_at\": \"2026-05-23T05:54:05.338Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-23T05:54:10.665515+00:00\"}]}, \"metrics\": {\"accuracy\": 0.805, \"majority_baseline\": 0.7151, \"lift\": 0.0899, \"n\": 1190, \"pass_precision\": 0.8637, \"pass_recall\": 0.8637, \"pass_f1\": 0.8637, \"fail_precision\": 0.6578, \"fail_recall\": 0.6578, \"fail_f1\": 0.6578, \"accuracy_ci_lower\": 0.7824, \"accuracy_ci_upper\": 0.8269, \"lift_ci_lower\": 0.0605, \"lift_ci_upper\": 0.121, \"train_loss\": 0.0416, \"eval_loss\": 0.082, \"wall_clock_seconds\": 7862, \"epoch_level\": {\"epoch_2_eval_loss\": 0.0728, \"epoch_3_eval_loss\": 0.082}}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_seed456/final\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-23T06:04:23.676Z\"}, \"full_trace_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T02:00:52.168Z\", \"updated_at\": \"2026-05-23T04:26:34.466Z\", \"hypothesis\": \"Full-trace multi-seed robustness (seed 123): full execution trace with chat-template-aware truncation achieves similar accuracy to seed42 (81.76%), establishing 3-seed statistics for the full_trace condition to support rebuttal against single-seed concerns\", \"parent\": \"full_trace_seed42_v5\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --gpu 0 --gradient_checkpointing --seed 123\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"846207\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_seed123.log\", \"submitted_at\": \"2026-05-23T02:01:28.528Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 123, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_test.jsonl\", \"wall_clock_seconds\": 8705.9, \"gpu_hours\": 2.42}, \"reproduce\": {\"finished_at\": \"2026-05-23T04:14:30.716Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-23T04:14:37.059166+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_seed123/final\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_seed123.log\", \"metrics\": {\"accuracy\": 0.7958, \"majority_baseline\": 0.7151, \"lift\": 0.0807, \"n\": 1190, \"pass_precision\": 0.8753, \"pass_recall\": 0.8331, \"pass_f1\": 0.8537, \"fail_precision\": 0.6263, \"fail_recall\": 0.7021, \"fail_f1\": 0.662, \"accuracy_ci_lower\": 0.7714, \"accuracy_ci_upper\": 0.8202, \"lift_ci_lower\": 0.0504, \"lift_ci_upper\": 0.1143, \"train_loss\": 0.0416, \"eval_loss\": 0.0842, \"wall_clock_seconds\": 7844, \"epoch_level\": {\"epoch_2_eval_loss\": 0.0761, \"epoch_3_eval_loss\": 0.0842}}, \"completed_at\": \"2026-05-23T04:26:34.466Z\"}, \"no_trace_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T23:42:13.616Z\", \"updated_at\": \"2026-05-23T00:13:57.506Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --gpu 0 --gradient_checkpointing --seed 456\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"839036\", \"log_path\": \"~/runs/trace-verdict-study/no_trace_seed456.log\", \"submitted_at\": \"2026-05-22T23:42:13.125Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/no_trace_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/test/\", \"wall_clock_seconds\": 1904.4, \"gpu_hours\": 0.53}, \"hypothesis\": \"no_trace multi-seed robustness (seed 456): implicit pathway (terminal execution state only, no diagnostic tokens) achieves similar accuracy to seed42 (75.13%) and seed123 (79.08%), establishing 3-seed statistics for the implicit pathway performance ceiling\", \"parent\": \"no_trace_seed42\", \"reproduce\": {\"finished_at\": \"2026-05-23T00:04:47.329Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-23T00:04:52.248703+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/no_trace_seed456/final\", \"metrics\": {\"accuracy\": 0.7504, \"pass_precision\": 0.8805, \"pass_recall\": 0.7532, \"pass_f1\": 0.8119, \"fail_precision\": 0.5455, \"fail_recall\": 0.7434, \"fail_f1\": 0.6292, \"eval_loss\": 0.6092, \"train_loss\": 0.1781, \"n\": 1190, \"accuracy_ci\": [0.7235, 0.7748]}, \"completed_at\": \"2026-05-23T00:13:57.506Z\"}, \"no_trace_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T23:16:32.361Z\", \"updated_at\": \"2026-05-22T23:46:07.341Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --gpu 0 --gradient_checkpointing --seed 123\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"837113\", \"log_path\": \"~/runs/trace-verdict-study/no_trace_seed123.log\", \"submitted_at\": \"2026-05-22T23:16:31.881Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/no_trace_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 123, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/test/\", \"wall_clock_seconds\": 1775.5, \"gpu_hours\": 0.49}, \"reproduce\": {\"finished_at\": \"2026-05-22T23:38:40.611Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-22T23:38:44.195419+00:00\"}]}, \"hypothesis\": \"no_trace multi-seed robustness (seed 123): implicit pathway (terminal execution state only, no diagnostic tokens) achieves similar accuracy to seed42 (75.13%), confirming the 93-97% implicit pathway ceiling and higher variance compared to explicit pathway conditions\", \"parent\": \"no_trace_seed42\", \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/no_trace_seed123/final\", \"metrics\": {\"accuracy\": 0.7908, \"pass_precision\": 0.8117, \"pass_recall\": 0.8971, \"pass_f1\": 0.8523, \"fail_precision\": 0.7434, \"fail_recall\": 0.5901, \"fail_f1\": 0.6581, \"n\": 1190}, \"completed_at\": \"2026-05-22T23:46:07.342Z\"}, \"nomarker_cross_he2mbpp_exception_only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T16:57:54.481Z\", \"updated_at\": \"2026-05-22T17:34:00.548Z\", \"spec\": {\"command\": \"python train/train_sft.py --condition cross_he2mbpp_exception_only_nomarker\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"821073\", \"log_path\": \"~/runs/trace-verdict-study/nomarker_cross_he2mbpp_exception_only.log\", \"submitted_at\": \"2026-05-22T16:57:53.985Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/cross_dataset/\", \"data_count\": 1640, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"cross_he2mbpp_exception_only_nomarker_test.jsonl\", \"wall_clock_seconds\": 2166.6, \"gpu_hours\": 0.6}, \"reproduce\": {\"finished_at\": \"2026-05-22T17:24:48.087Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-22T17:24:53.191115+00:00\"}]}, \"hypothesis\": \"Cross-dataset nomarker ablation: removing format markers from exception_only in the HE→MBPP cross-dataset setting will show minimal accuracy drop (similar to in-distribution ~2pp), confirming that cross-dataset generalization relies on semantic exception content rather than format marker shortcuts.\", \"parent\": \"cross_he2mbpp_exception_only_seed42\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/nomarker_cross_he2mbpp/final\", \"log_path\": \"/root/runs/trace-verdict-study/nomarker_cross_he2mbpp_exception_only.log\", \"metrics\": {\"accuracy\": 0.9546, \"pass_precision\": 0.9943, \"pass_recall\": 0.9396, \"pass_f1\": 0.9662, \"fail_precision\": 0.8801, \"fail_recall\": 0.9879, \"fail_f1\": 0.9309, \"eval_loss\": 1.09, \"train_loss\": 0.247}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T17:34:00.548Z\"}, \"gradient_masking_qwen7b_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T14:59:22.718Z\", \"updated_at\": \"2026-05-22T17:31:48.573Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition exception_only --gpu 0 --gradient_mask_ratio 0.998 --gradient_checkpointing --seed 456 --wandb_project trace-verdict-study --wandb_run_name gradient_masking_qwen7b_seed456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/gradient_masking_qwen7b_seed456\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"815300\", \"log_path\": \"~/runs/trace-verdict-study/gradient_masking_qwen7b_seed456.log\", \"submitted_at\": \"2026-05-22T14:59:22.210Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/test/\", \"wall_clock_seconds\": 9146.4, \"gpu_hours\": 2.54}, \"reproduce\": {\"finished_at\": \"2026-05-22T16:16:37.982Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-22T16:16:41.493373+00:00\"}]}, \"hypothesis\": \"Gradient masking seed robustness (seed 456): gradient masking (keeping only top 0.2% gradient signals) on exception_only condition achieves comparable accuracy to seed42 and seed123, confirming that content quality explains ~95% of performance consistently across seeds.\", \"parent\": \"gradient_masking_qwen7b_seed123\", \"metrics\": {\"accuracy\": 0.9933, \"pass_precision\": 1, \"pass_recall\": 0.9906, \"pass_f1\": 0.9953, \"fail_precision\": 0.9769, \"fail_recall\": 1, \"fail_f1\": 0.9883, \"n\": 1190, \"accuracy_ci\": [0.9882, 0.9975], \"majority_baseline\": 0.7151, \"lift\": 0.2782, \"eval_loss\": 0.0381, \"train_loss\": 1.6031}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/gradient_masking_qwen7b_seed456/final\", \"log_path\": \"~/runs/trace-verdict-study/gradient_masking_qwen7b_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T17:31:48.573Z\"}, \"gradient_masking_qwen7b_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T13:14:19.383Z\", \"updated_at\": \"2026-05-22T14:58:04.946Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition exception_only --gpu 0 --gradient_mask_ratio 0.998 --gradient_checkpointing --seed 123 --wandb_project trace-verdict-study --wandb_run_name gradient_masking_qwen7b_seed123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/gradient_masking_qwen7b_seed123\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"804127\", \"log_path\": \"~/runs/trace-verdict-study/gradient_masking_qwen7b_seed123.log\", \"submitted_at\": \"2026-05-22T13:14:18.864Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 123, \"wall_clock_seconds\": 6226.1, \"gpu_hours\": 1.73}, \"reproduce\": {\"finished_at\": \"2026-05-22T14:32:55.622Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-22T14:33:00.090320+00:00\"}]}, \"hypothesis\": \"Gradient masking (keeping only top 0.2% gradient signals) on exception_only condition with seed 123 achieves comparable accuracy to seed 42 (98.99%), confirming that content quality explains ~95% of performance and gradient dilution accounts for at most ~5%\", \"metrics\": {\"accuracy\": 0.9933, \"pass_precision\": 1, \"pass_recall\": 0.9906, \"pass_f1\": 0.9953, \"fail_precision\": 0.9769, \"fail_recall\": 1, \"fail_f1\": 0.9883, \"n\": 1190, \"accuracy_ci\": [0.9882, 0.9975], \"majority_baseline\": 0.7151, \"lift\": 0.2782}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/gradient_masking_qwen7b_seed123/final\", \"log_path\": \"/root/runs/trace-verdict-study/gradient_masking_qwen7b_seed123.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T14:58:04.946Z\"}, \"exc_message_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T12:04:51.079Z\", \"updated_at\": \"2026-05-22T13:17:57.033Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python eval/evaluate.py --condition exc_message_only --checkpoint_dir .../exc_message_only_seed42/final --data_dir .../exc_subcomponent/\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"799129\", \"log_path\": \"~/runs/trace-verdict-study/exc_message_only_seed42.log\", \"submitted_at\": \"2026-05-22T12:04:50.609Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exc_subcomponent/\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"wall_clock_seconds\": 4384.5, \"gpu_hours\": 1.22}, \"hypothesis\": \"Exception message alone (without type or stacktrace) retains near-perfect diagnostic signal for verdict prediction, because the error message text contains the semantic description of what went wrong\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exc_message_only_seed42/final\", \"log_path\": \"~/runs/trace-verdict-study/exc_message_only_seed42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T13:17:55.135Z\", \"metrics\": {\"accuracy\": 0.995, \"pass_precision\": 1, \"pass_recall\": 0.993, \"pass_f1\": 0.996, \"fail_precision\": 0.983, \"fail_recall\": 1, \"fail_f1\": 0.991, \"n\": 1190, \"accuracy_ci\": [0.991, 0.998]}}, \"exc_stacktrace_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T10:32:56.837Z\", \"updated_at\": \"2026-05-22T12:24:40.128Z\", \"spec\": {\"command\": \"train_sft.py --condition exc_stacktrace_only --seed 42 --gradient_checkpointing\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"794694\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exc_stacktrace_only_seed42.log\", \"submitted_at\": \"2026-05-22T10:32:56.375Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exc_stacktrace_only_seed42/final\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exc_subcomponent/\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"wall_clock_seconds\": 6703.8, \"gpu_hours\": 1.86}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.998, \"pass_precision\": 1, \"pass_recall\": 0.998, \"pass_f1\": 0.999, \"fail_precision\": 0.994, \"fail_recall\": 1, \"fail_f1\": 0.997, \"n\": 1190, \"accuracy_ci\": [0.996, 1]}, \"hypothesis\": \"Exception stacktrace alone (without exception message) contains sufficient diagnostic signal for near-perfect verdict prediction, because stacktrace structure encodes the causal chain of function calls leading to failure\", \"completed_at\": \"2026-05-22T12:24:40.128Z\"}, \"exc_type_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T09:48:12.482Z\", \"updated_at\": \"2026-05-22T09:49:19.739Z\", \"hypothesis\": \"Exception type alone (e.g. 'ValueError') without message or stacktrace retains most of exception_only's diagnostic power, since the error type is the primary signal for verdict classification\", \"parent\": \"vota_exception_only_seed42_v2\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition exc_type_only --data_dir /root/autodl-tmp/trace-verdict-study-data/exc_subcomponent/ --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/exc_type_only_seed42 --gpu 0 --seed 42 --gradient_checkpointing --wandb_project trace-verdict-study --wandb_run_name exc_type_only_seed42 2>&1 | tee /root/autodl-tmp/trace-verdict-study-checkpoints/exc_type_only_seed42.log\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"791134\", \"log_path\": \"~/runs/trace-verdict-study/exc_type_only_seed42.log\", \"submitted_at\": \"2026-05-22T09:49:19.279Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"gradient_masking_qwen7b_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T08:04:51.202Z\", \"updated_at\": \"2026-05-22T08:04:51.202Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition exception_only --gpu 0 --gradient_mask_ratio 0.998 --gradient_checkpointing --seed 42 --wandb_project trace-verdict-study --wandb_run_name gradient_masking_qwen7b_seed42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/gradient_masking_qwen7b_seed42 2>&1 | tee /root/autodl-tmp/trace-verdict-study-checkpoints/gradient_masking_qwen7b_seed42.log\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"782368\", \"log_path\": \"~/runs/trace-verdict-study/gradient_masking_qwen7b_seed42.log\", \"submitted_at\": \"2026-05-22T08:04:50.690Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"cross_dataset_batch\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T04:34:14.081Z\", \"updated_at\": \"2026-05-22T06:04:27.930Z\", \"spec\": {\"command\": \"bash /root/trace-verdict-study/scripts/run_cross_dataset.sh\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"745582\", \"log_path\": \"~/runs/trace-verdict-study/cross_dataset_batch.log\", \"submitted_at\": \"2026-05-22T04:34:13.600Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/cross_dataset/\", \"data_count\": 11820, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42}}, \"cross_he2mbpp_no_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T04:33:42.548Z\", \"updated_at\": \"2026-05-22T06:04:07.456Z\", \"hypothesis\": \"Cross-dataset generalization HE→MBPP with no_trace baseline: without execution traces, SFT relies on dataset-specific code patterns that do not transfer well across datasets, predicting larger accuracy drop when trained on HumanEval and tested on MBPP.\", \"spec\": {\"command\": \"/root/miniconda3/bin/python train/train_sft.py --condition cross_he2mbpp_no_trace --data_dir /root/autodl-tmp/trace-verdict-study-data/cross_dataset/ --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/cross_he2mbpp_no_trace --gradient_checkpointing --gpu 0 --seed 42\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/cross_dataset/\", \"data_count\": 1640, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/cross_he2mbpp_no_trace/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/cross_dataset_batch.log\", \"metrics\": {\"accuracy\": 0.7056, \"pass_precision\": 0.736, \"pass_recall\": 0.8941, \"pass_f1\": 0.8074, \"fail_precision\": 0.5478, \"fail_recall\": 0.2857, \"fail_f1\": 0.3756, \"majority_baseline\": 0.6902, \"lift\": 0.0155}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T06:04:07.456Z\"}, \"cross_he2mbpp_exception_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T04:33:40.785Z\", \"updated_at\": \"2026-05-22T06:04:05.530Z\", \"hypothesis\": \"Cross-dataset generalization HE→MBPP with exception_only: exception trace SFT learns transferable code reasoning patterns that generalize across datasets, predicting smaller accuracy drop compared to no_trace baseline when trained on HumanEval and tested on MBPP.\", \"spec\": {\"command\": \"/root/miniconda3/bin/python train/train_sft.py --condition cross_he2mbpp_exception_only --data_dir /root/autodl-tmp/trace-verdict-study-data/cross_dataset/ --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/cross_he2mbpp_exception_only --gradient_checkpointing --gpu 0 --seed 42\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/cross_dataset/\", \"data_count\": 1640, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/cross_he2mbpp_exception_only/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/cross_dataset_batch.log\", \"metrics\": {\"accuracy\": 0.9941, \"pass_precision\": 0.998, \"pass_recall\": 0.9936, \"pass_f1\": 0.9957, \"fail_precision\": 0.9858, \"fail_recall\": 0.9955, \"fail_f1\": 0.9906, \"majority_baseline\": 0.6902, \"lift\": 0.304}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T06:04:05.530Z\"}, \"cross_mbpp2he_no_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T04:33:47.580Z\", \"updated_at\": \"2026-05-22T06:03:35.271Z\", \"hypothesis\": \"Cross-dataset generalization MBPP→HE with no_trace baseline: without execution traces, SFT relies on dataset-specific code patterns that do not transfer well across datasets, predicting larger accuracy drop when trained on MBPP and tested on HumanEval.\", \"spec\": {\"command\": \"/root/miniconda3/bin/python train/train_sft.py --condition cross_mbpp2he_no_trace --data_dir /root/autodl-tmp/trace-verdict-study-data/cross_dataset/ --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/cross_mbpp2he_no_trace --gradient_checkpointing --gpu 0 --seed 42\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/cross_dataset/\", \"data_count\": 4270, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42}}, \"cross_mbpp2he_exception_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T04:33:45.492Z\", \"updated_at\": \"2026-05-22T06:03:33.280Z\", \"hypothesis\": \"Cross-dataset generalization MBPP→HE with exception_only: exception trace SFT learns transferable code reasoning patterns that generalize across datasets, predicting smaller accuracy drop compared to no_trace baseline when trained on MBPP and tested on HumanEval.\", \"spec\": {\"command\": \"/root/miniconda3/bin/python train/train_sft.py --condition cross_mbpp2he_exception_only --data_dir /root/autodl-tmp/trace-verdict-study-data/cross_dataset/ --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/cross_mbpp2he_exception_only --gradient_checkpointing --gpu 0 --seed 42\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/cross_dataset/\", \"data_count\": 4270, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42}}, \"attention_gradient_analysis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T04:08:33.645Z\", \"updated_at\": \"2026-05-22T04:29:04.760Z\", \"hypothesis\": \"In the full_trace model, execution trace tokens dominate input length (~70%+ of tokens) but receive disproportionately low attention and gradient signal at the verdict position, demonstrating gradient dilution — non-diagnostic trace tokens dilute learning signal away from source code and test code sections.\", \"parent\": \"full_trace_seed42_v5\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && HF_HOME=/root/autodl-tmp/.hf_cache /root/miniconda3/bin/python analysis/attention_gradient_analysis.py 2>&1 | tee /root/trace-verdict-study/artifacts/attention_gradient_analysis/run.log\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"742526\", \"log_path\": \"~/runs/trace-verdict-study/attention_gradient_analysis.log\", \"submitted_at\": \"2026-05-22T04:08:42.428Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"notes\": \"Gradient analysis produced NaN (abandoned). Attention dilution ratio = 5.12× usable as supplementary evidence only (needs caveat about circularity). MF-3 core response shifted to model-free metrics (diagnostic_token_ratio r=0.949 p=0.014, pass_fail_diff). Token categories adapted: source_code/test_code/execution_trace/framing (data has variable state logs, not Python tracebacks).\"}, \"deepseek_loop_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 2, \"created_at\": \"2026-05-19T17:29:34.281Z\", \"updated_at\": \"2026-05-22T03:27:59.873Z\", \"hypothesis\": \"Cross-model component ablation: loop_only (loop compression summaries only) on DeepSeek-Coder-6.7B. Tests if Tier 2 signal (loop_only ~85% on Qwen-7B, significantly below Tier 1 ae_only/exception_only ≥99%) shows same tier gap on DeepSeek. Combined with deepseek_ae_only (98.74%), this validates two-tier pattern across 2/4 models. Responds to Round 13 SF-5.\", \"parent\": \"vota_loop_only_seed42\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"failure_reason\": \"\", \"completed_at\": \"2026-05-19T17:39:08.696Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.8126, \"accuracy_ci_lower\": 0.7908, \"accuracy_ci_upper\": 0.8345, \"fail_recall\": 0.6372, \"pass_recall\": 0.8825}}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T20:27:03.192709+00:00\"}]}, \"reproduce\": {\"finished_at\": \"2026-05-19T20:26:57.867Z\"}, \"spec\": {\"command\": \"python train/train_sft.py --condition loop_only --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_loop_only --gradient_checkpointing --gpu 0 --seed 42 --wandb_project trace-verdict-study --wandb_run_name deepseek_loop_only_seed42\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"740369\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_loop_only_seed42.log\", \"submitted_at\": \"2026-05-22T03:24:08.722Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/loop_only_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 42, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/loop_only_test.jsonl\", \"wall_clock_seconds\": 231.2, \"gpu_hours\": 0.06}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.8126, \"accuracy_ci_lower\": 0.7908, \"accuracy_ci_upper\": 0.8345, \"fail_recall\": 0.6372, \"pass_recall\": 0.8825}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_loop_only/final\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_loop_only_seed42.log\"}, \"deepseek_ae_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-19T20:36:36.821Z\", \"updated_at\": \"2026-05-22T03:04:09.354Z\", \"hypothesis\": \"Cross-model component ablation: ae_only (actual/expected values only) on DeepSeek-Coder-6.7B. Tests if Tier 1 signal (ae_only ≥99% on Qwen-7B) generalizes to DeepSeek. Responds to Round 13 SF-5 reviewer concern about single-model evidence for two-tier pattern.\", \"parent\": \"vota_ae_only_seed42\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"finished_at\": \"2026-05-19T23:08:32.917Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T23:08:37.293936+00:00\"}], \"previous_failure\": {\"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9874, \"accuracy_ci_lower\": 0.9807, \"accuracy_ci_upper\": 0.9933, \"fail_recall\": 0.959, \"pass_recall\": 0.999, \"fail_f1\": 0.977, \"pass_f1\": 0.991}}}, \"completed_at\": \"2026-05-19T23:10:38.180Z\", \"spec\": {\"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/ae_only_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 42}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9874, \"accuracy_ci_lower\": 0.9807, \"accuracy_ci_upper\": 0.9933, \"fail_recall\": 0.959, \"pass_recall\": 0.999, \"fail_f1\": 0.977, \"pass_f1\": 0.991}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_ae_only/final\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_ae_only_seed42.log\"}, \"exception_only_padded2048_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T18:24:05.794Z\", \"updated_at\": \"2026-05-21T20:57:40.973Z\", \"hypothesis\": \"Padding exception-only trace inputs to 2048 tokens maintains high verdict accuracy comparable to unpadded training, validating that fixed-length padding does not degrade the model's ability to classify pass/fail from exception traces.\", \"spec\": {\"command\": \"/root/miniconda3/bin/python train/train_sft.py --condition exception_only_padded2048 --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_padded2048_seed42 --wandb_project trace-verdict-study --wandb_run_name exception_only_padded2048_seed42\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"720490\", \"log_path\": \"~/runs/trace-verdict-study/exception_only_padded2048_seed42.log\", \"submitted_at\": \"2026-05-21T18:29:53.466Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_padded2048_{train,test}.jsonl\", \"data_count\": 5910, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"wall_clock_seconds\": 8867.5, \"gpu_hours\": 2.46}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9983, \"pass_precision\": 1, \"pass_recall\": 0.9976, \"pass_f1\": 0.9988, \"fail_precision\": 0.9941, \"fail_recall\": 1, \"fail_f1\": 0.9971, \"majority_baseline\": 0.7151, \"lift\": 0.2832, \"n\": 1190}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_padded2048_seed42/final\", \"log_path\": \"/root/runs/trace-verdict-study/exception_only_padded2048_seed42.log\", \"completed_at\": \"2026-05-21T20:57:40.973Z\"}, \"regex_nomarker_baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T19:03:04.213Z\", \"updated_at\": \"2026-05-21T19:03:23.905Z\", \"hypothesis\": \"Regex baselines (B1-B5) on nomarker condition will show significant degradation, especially B5 which relies on the [No exception data in trace] marker. This reveals the marker-condition B5=99.33% is a format artifact, not genuine code reasoning.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python eval/regex_baseline.py on nomarker test data\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_nomarker_test.jsonl\", \"data_count\": 1190, \"model_name\": \"regex_heuristics\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"completed_at\": \"2026-05-21T19:03:22.128Z\", \"metrics\": {\"B5_marker_acc\": 0.9933, \"B5_nomarker_acc\": 0.2849, \"B5_delta_pp\": -70.84, \"B1_marker_acc\": 0.9345, \"B1_nomarker_acc\": 0.7151, \"B4_marker_acc\": 0.9361, \"B4_nomarker_acc\": 0.9361, \"B5b_nomarker_acc\": 0.9345, \"n\": 1190}}, \"fewshot_gpt41_no_trace_0shot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T18:07:53.581Z\", \"updated_at\": \"2026-05-21T18:12:03.562Z\", \"hypothesis\": \"GPT-4.1 zero-shot on no_trace condition can outperform SFT Qwen-7B because frontier LLMs have stronger code understanding that compensates for missing trace information.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python eval/fewshot_baseline.py --model gpt41 --condition no_trace --shots 0\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/no_trace_test.jsonl\", \"data_count\": 1190, \"model_name\": \"gpt-4.1\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"/tmp/fewshot_gpt41_no_trace_0shot.log\"}, \"completed_at\": \"2026-05-21T18:10:00.395Z\", \"metrics\": {\"accuracy\": 0.7731, \"fail_f1\": 0.6608}}, \"fewshot_gpt4o_no_trace_0shot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T18:07:49.983Z\", \"updated_at\": \"2026-05-21T18:12:02.686Z\", \"hypothesis\": \"GPT-4o zero-shot on no_trace condition can outperform SFT Qwen-7B because frontier LLMs have stronger code understanding that compensates for missing trace information.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python eval/fewshot_baseline.py --model gpt4o --condition no_trace --shots 0\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/no_trace_test.jsonl\", \"data_count\": 1190, \"model_name\": \"gpt-4o\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"/tmp/fewshot_gpt4o_no_trace_0shot.log\"}, \"completed_at\": \"2026-05-21T18:09:54.994Z\", \"metrics\": {\"accuracy\": 0.8445, \"fail_f1\": 0.7543}}, \"fewshot_gpt41_exception_only_3shot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T18:07:52.778Z\", \"updated_at\": \"2026-05-21T18:12:01.712Z\", \"hypothesis\": \"Adding 3-shot examples to GPT-4.1 improves exception_only verdict prediction over zero-shot by providing task format demonstrations.\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"python eval/fewshot_baseline.py --model gpt41 --condition exception_only --shots 3\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_test.jsonl\", \"data_count\": 1190, \"model_name\": \"gpt-4.1\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"/tmp/fewshot_gpt41_exception_only_3shot.log\"}, \"completed_at\": \"2026-05-21T18:09:58.619Z\", \"metrics\": {\"accuracy\": 0.8193, \"fail_f1\": 0.7413}}, \"fewshot_gpt41_exception_only_0shot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T18:07:51.545Z\", \"updated_at\": \"2026-05-21T18:12:00.304Z\", \"hypothesis\": \"GPT-4.1 zero-shot on exception_only condition performs comparably to GPT-4o because both are frontier models with similar code reasoning capabilities.\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"python eval/fewshot_baseline.py --model gpt41 --condition exception_only --shots 0\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_test.jsonl\", \"data_count\": 1190, \"model_name\": \"gpt-4.1\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"/tmp/fewshot_gpt41_exception_only_0shot.log\"}, \"completed_at\": \"2026-05-21T18:09:56.668Z\", \"metrics\": {\"accuracy\": 0.8218, \"fail_f1\": 0.7452}}, \"fewshot_gpt4o_exception_only_3shot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T18:07:48.528Z\", \"updated_at\": \"2026-05-21T18:11:59.415Z\", \"hypothesis\": \"Adding 3-shot examples to GPT-4o improves exception_only verdict prediction over zero-shot by providing task format demonstrations and calibrating output expectations.\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"python eval/fewshot_baseline.py --model gpt4o --condition exception_only --shots 3\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_test.jsonl\", \"data_count\": 1190, \"model_name\": \"gpt-4o\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"/tmp/fewshot_gpt4o_exception_only_3shot.log\"}, \"completed_at\": \"2026-05-21T18:09:52.461Z\", \"metrics\": {\"accuracy\": 0.8681, \"fail_f1\": 0.7995}}, \"fewshot_gpt4o_exception_only_0shot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T18:07:46.863Z\", \"updated_at\": \"2026-05-21T18:11:58.377Z\", \"hypothesis\": \"Frontier LLM (GPT-4o) with zero-shot prompting can match SFT Qwen-7B on exception_only test verdict prediction because the task may be solvable via general code reasoning without task-specific fine-tuning.\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"python eval/fewshot_baseline.py --model gpt4o --condition exception_only --shots 0\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_test.jsonl\", \"data_count\": 1190, \"model_name\": \"gpt-4o\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"/tmp/fewshot_gpt4o_exception_only_0shot.log\"}, \"completed_at\": \"2026-05-21T18:09:49.653Z\", \"metrics\": {\"accuracy\": 0.8798, \"fail_f1\": 0.8228}}, \"deepseek_exception_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 1, \"conclusion\": \"killed\", \"failure_reason\": \"DDL 优先级降低，不再重跑（v2 已完成 99.50%）\", \"created_at\": \"2026-05-15T15:31:02.686Z\", \"updated_at\": \"2026-05-21T15:32:00.000Z\", \"hypothesis\": \"Cross-model seed robustness: exception_only with seed=123 on DeepSeek-Coder-6.7B (plan_008). Further validates exception signal cross-model generalization (99.33% seed42).\", \"reproduce\": {\"finished_at\": \"2026-05-15T20:04:43.247Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T20:04:44.489564+00:00\"}], \"previous_failure\": {\"conclusion\": \"negative\", \"metrics\": {\"accuracy\": 0.9109, \"pass_precision\": 1, \"pass_recall\": 0.993, \"pass_f1\": 0.996, \"fail_precision\": 0.976, \"fail_recall\": 0.705, \"fail_f1\": 0.818, \"ci_95\": [0.894, 0.926], \"train_loss\": 0.122, \"train_runtime_sec\": 6384}, \"notes\": \"NEGATIVE: accuracy 91.09% vs seed42 99.83% (-8.74pp). fail_recall=0.705, train_loss=0.122 偏高。DeepSeek exception_only 对 seed 不鲁棒，seed42 的 99.83% 可能是 LoRA 初始化运气。Exception signal 仍有效（+19.6pp over baseline）但跨模型稳定性不成立。\"}}, \"completed_at\": \"2026-05-15T20:08:02.101Z\", \"notes\": \"NEGATIVE: accuracy 91.09% vs seed42 99.83% (-8.74pp). fail_recall=0.705, train_loss=0.122 偏高。DeepSeek exception_only 对 seed 不鲁棒，seed42 的 99.83% 可能是 LoRA 初始化运气。Exception signal 仍有效（+19.6pp over baseline）但跨模型稳定性不成立。\", \"outputs\": {\"predictions_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_exception_only_seed123/checkpoint-148/predictions.jsonl\"}, \"parent\": \"deepseek_exception_only_seed42\"}, \"codellama13b_label_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:23:45.493Z\", \"updated_at\": \"2026-05-21T15:32:00.000Z\", \"conclusion\": \"killed\", \"failure_reason\": \"DDL 优先级降低，不再重跑\"}, \"qwen15b_label_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:23:46.314Z\", \"updated_at\": \"2026-05-21T15:32:00.000Z\", \"conclusion\": \"killed\", \"failure_reason\": \"DDL 优先级降低，不再重跑\"}, \"qwen1.5b_no_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:27:36.233Z\", \"updated_at\": \"2026-05-21T15:23:12.652Z\", \"spec\": {\"hypothesis\": \"Multi-scale baseline: no_trace on Qwen-2.5-Coder-1.5B.\", \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"condition\": \"no_trace\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"account\": \"root\", \"command\": \"export CUDA_VISIBLE_DEVICES=0 && python train/train_sft.py --condition no_trace --gpu 0 --seed 42 --model_name /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen1.5b_no_trace_seed42\", \"pid\": \"706059\", \"log_path\": \"/tmp/qwen15b_nt_train.log\", \"submitted_at\": \"2026-05-21T14:48:00Z\", \"submitted_via\": \"tmux\", \"backend\": \"tmux\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/no_trace_train.jsonl\", \"data_count\": 4720, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"no_trace_test.jsonl (1190 samples)\"}, \"conclusion\": \"success\", \"hypothesis\": \"Qwen-1.5B no_trace 应在 65-75% (≈majority baseline)，确认无 trace 小模型表现更差、scale 无法补偿\", \"notes\": \"Eval completed 2026-05-21. Accuracy 72.6% (vs qwen15b_no_trace_seed42 67.31%, +5.3pp). 独立训练 checkpoint（不同训练命令/输出目录），非简单重复。 Lift over majority baseline +1.1pp, CI 含 0 → 不显著。\", \"metrics\": {\"accuracy\": 0.7261, \"accuracy_ci_lower\": 0.7008, \"accuracy_ci_upper\": 0.7529, \"majority_baseline\": 0.7151, \"lift_pp\": 1.09, \"pass_precision\": 0.831, \"pass_recall\": 0.774, \"pass_f1\": 0.802, \"fail_precision\": 0.516, \"fail_recall\": 0.605, \"fail_f1\": 0.557}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen1.5b_no_trace_seed42/final\", \"log_path\": \"/tmp/qwen15b_nt_train.log\"}, \"codellama_exception_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-16T07:27:41.475Z\", \"updated_at\": \"2026-05-21T15:22:00.000Z\", \"spec\": {\"hypothesis\": \"Multi-family validation: exception_only on CodeLlama-13B-Instruct. Tests if exception dominance generalizes to LLaMA family.\", \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 42, \"condition\": \"exception_only\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_train.jsonl\", \"data_count\": 4720, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"exception_only_test.jsonl (1190 samples)\"}, \"conclusion\": \"killed\", \"failure_reason\": \"确认为 codellama13b_exception_only_seed42 (99.83%) 的重复条目，不需重跑\", \"hypothesis\": \"CodeLlama-13B exception_only 应达 ≥99.33% accuracy，与其他 3 模型一致，确认 minimal sufficient signal 跨 4 模型 3 架构 1.5B-13B universal\", \"notes\": \"重复条目，已在 codellama13b_exception_only_seed42 (99.83%) 完成。命名差异：codellama_ → codellama13b_\"}, \"qwen7b_full_trace_seed456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T08:06:16.598Z\", \"updated_at\": \"2026-05-21T12:25:14.457Z\", \"hypothesis\": \"Qwen-7B full_trace seed456 应在 ~81% 附近（与 seed42=81.76%, seed123=80.20% 一致），为 MF-3 multi-seed 要求补齐 full_trace 方差估计。3-seed mean 将替换 Table 2 中的占位符。\", \"parent\": \"full_trace_seed42_v5\", \"spec\": {\"command\": \"export CUDA_VISIBLE_DEVICES=1 && python train/train_sft.py --condition full_trace --seed 456 --gpu 0 --gradient_checkpointing --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_seed456\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"693144\", \"log_path\": \"/tmp/seed456_train.log\", \"submitted_at\": \"2026-05-21T10:05:00Z\", \"submitted_via\": \"tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/full_trace_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"full_trace_test.jsonl (1190 samples)\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_seed456/final\", \"wall_clock_seconds\": 8387.3, \"gpu_hours\": 2.33}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.8235, \"ci_lower\": 0.8017, \"ci_upper\": 0.8454, \"majority_baseline\": 0.7151, \"lift_pp\": 10.84, \"pass_precision\": 0.8885, \"pass_recall\": 0.8613, \"pass_f1\": 0.8747, \"fail_precision\": 0.6767, \"fail_recall\": 0.7286, \"fail_f1\": 0.7017, \"train_loss\": 0.0416, \"eval_loss\": 0.0794}, \"reproduce\": {\"finished_at\": \"2026-05-21T12:24:44.143Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-21T12:24:47.319Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T12:24:54.190947+00:00\"}]}}, \"qwen7b_full_trace_seed123\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-21T07:29:49.744Z\", \"updated_at\": \"2026-05-21T10:07:21.793Z\", \"hypothesis\": \"Qwen-7B full_trace seed123 应在 ~81% 附近（与 seed42=81.76% 一致），为 MF-3 multi-seed 要求补齐 full_trace 方差估计。full_trace 是 C2 \\\"more info hurts\\\" claim 的锚点，单 seed 在 review 中被标记为风险。\", \"parent\": \"full_trace_seed42_v5\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-21T07:30:12.716Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_seed123 --wandb_project trace-verdict-study --wandb_run_name qwen7b_full_trace_seed123 && python eval/evaluate.py --condition full_trace --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_seed123/final --gpu 0 --save_predictions\\\"\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-21T09:59:10.601Z\", \"training_hours\": 2.48}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"completed_at\": \"2026-05-21T07:32:51.653Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T07:32:55.588576+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T09:59:17.515644+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python train/train_sft.py --condition full_trace --gpu 0 --seed 123 --gradient_checkpointing --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_seed123 --wandb_project trace-verdict-study --wandb_run_name qwen7b_full_trace_seed123_v2\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"686085\", \"log_path\": \"/tmp/seed123_train.log\", \"submitted_at\": \"2026-05-21T15:41:44Z\", \"submitted_via\": \"tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/full_trace_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 123, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"full_trace_test.jsonl (1190 samples)\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_seed123/final\"}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.802, \"ci_lower\": 0.778, \"ci_upper\": 0.825, \"majority_baseline\": 0.715, \"lift_pp\": 8.7, \"pass_precision\": 0.88, \"pass_recall\": 0.84, \"pass_f1\": 0.86, \"fail_precision\": 0.64, \"fail_recall\": 0.7, \"fail_f1\": 0.67, \"train_loss\": 0.0415, \"eval_loss\": 0.0827}}, \"qwen7b_full_trace_seed456\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-21T07:29:51.585Z\", \"updated_at\": \"2026-05-21T08:06:01.308Z\", \"hypothesis\": \"Qwen-7B full_trace seed456 应在 ~81% 附近（与 seed42=81.76% 一致），为 MF-3 multi-seed 要求补齐 full_trace 方差估计。3-seed mean 将替换 Table 2 中的单 seed 值。\", \"parent\": \"full_trace_seed42_v5\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-21T07:30:20.277Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --gpu 0 --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_seed456 --wandb_project trace-verdict-study --wandb_run_name qwen7b_full_trace_seed456 && python eval/evaluate.py --condition full_trace --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_seed456/final --gpu 0 --save_predictions\\\"\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-21T07:33:03.046Z\", \"training_hours\": 0.05}, \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 4.64 GiB. GPU 0 has a total capacity of 94.97 GiB of which 225.56 MiB is free. Including non-PyTorch memory, this process has 94.74 GiB memory in use. Of the allocated memory 87.18 GiB is allocated by PyTorch, an\", \"completed_at\": \"2026-05-21T07:33:08.094Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T07:33:15.672357+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 /root/miniconda3/bin/python train/train_sft.py --condition full_trace --gpu 0 --seed 456 --gradient_checkpointing --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_seed456 --wandb_project trace-verdict-study --wandb_run_name qwen7b_full_trace_seed456\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"683873\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_full_trace_seed456.log\", \"submitted_at\": \"2026-05-21T15:41:46Z\", \"submitted_via\": \"tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"full_trace_test.jsonl (1190 samples)\"}, \"conclusion\": \"failed\", \"checkpoint_path\": \"N/A\"}, \"codellama13b_ae_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-19T12:55:37.558Z\", \"updated_at\": \"2026-05-21T07:25:52.875Z\", \"hypothesis\": \"CodeLlama-13B ae_only 应达 95-99% accuracy（介于 exception_only 99.83% 和 loop_only 77.40% 之间），验证 Tier 1/2 hierarchy 跨非 Qwen 架构成立。MF-2 要求至少一个非 Qwen 模型的 component ablation。\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-19T12:56:46.334Z\"}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-19T17:19:54.586Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"command\": \"CUDA_VISIBLE_DEVICES=1 /root/miniconda3/bin/python train/train_sft.py --condition ae_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf/ --seed 42 --gradient_checkpointing --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_ae_only_seed42/ --wandb_project trace-verdict-study --wandb_run_name codellama13b_ae_only_seed42\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/\", \"data_count\": 4720, \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 42}, \"metrics\": {\"accuracy\": 0.9908, \"accuracy_ci_lower\": 0.9849, \"accuracy_ci_upper\": 0.9958, \"pass_f1\": 0.9935, \"fail_f1\": 0.984, \"majority_baseline\": 0.7151}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_ae_only_seed42/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_ae_only_seed42/runs/May19_20-58-59_autodl-container-ylrall2a4g-cea5a084\", \"conclusion\": \"success\"}, \"vota_seed42_v5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:46:04.015Z\", \"updated_at\": \"2026-05-21T06:31:45.878Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --gpu 1 --wandb_project trace-verdict-study --wandb_run_name vota_seed42_v5\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"940786\", \"log_path\": \"~/runs/trace-verdict-study/vota_seed42_v5.log\", \"submitted_at\": \"2026-05-15T01:46:03.990Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/vota_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/vota/final/\", \"wall_clock_seconds\": 8443, \"gpu_hours\": 2.35}, \"hypothesis\": \"VOTA trace provides verdict accuracy lift over no-trace baseline (v5: fixed chat template overhead, all labels preserved)\", \"reproduce\": {\"finished_at\": \"2026-05-15T04:08:40.446Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T04:08:41.358997+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9941, \"pass_precision\": 1, \"pass_recall\": 0.9918, \"pass_f1\": 0.9959, \"fail_precision\": 0.9798, \"fail_recall\": 1, \"fail_f1\": 0.9898, \"n\": 1190, \"tp\": 844, \"fp\": 0, \"tn\": 339, \"fn\": 7}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T04:21:27.059Z\"}, \"cross_model_calibration\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T06:14:12.232Z\", \"updated_at\": \"2026-05-21T06:14:57.965Z\", \"hypothesis\": \"Calibration quality (ECE and Brier Score) of exception_only fine-tuned models is universally strong across different model architectures and sizes, not specific to Qwen-7B.\", \"spec\": {\"command\": \"bash eval/run_cross_model_calibration.sh\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_test.jsonl\", \"data_count\": 1190, \"model_name\": \"Qwen-7B/Qwen-1.5B/CodeLlama-13B/DeepSeek-6.7B\", \"seed\": 42, \"checkpoint_source\": \"exception_only checkpoints for all 4 models\", \"eval_data\": \"exception_only_test.jsonl (1190 samples)\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/cross_model_calibration/\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/cross_model_calibration/calibration.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T06:14:57.965Z\"}, \"codellama13b_label_only_seed123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T21:19:06.021Z\", \"updated_at\": \"2026-05-21T01:06:42.518Z\", \"hypothesis\": \"CodeLlama-13B label_only seed123 确认 collapse 是否 systematic：seed42=28.5% (全预测 fail)，同 DeepSeek collapse pattern。如 seed123 也崩溃 → \\\"label-only collapse is systematic for non-Qwen architectures\\\"。\", \"parent\": \"codellama13b_label_only_seed42_v2\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-20T21:19:41.720Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --label_only_loss --gpu 0 --seed 123 --output_dir /root/trace-verdict-study/outputs/codellama13b_label_only_seed123_v2 --wandb_project trace-verdict-study --wandb_run_name codellama13b_label_only_seed123_v2 && python eval/evaluate.py --condition full_trace --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --checkpoint_dir /root/trace-verdict-study/outputs/codellama13b_label_only_seed123_v2/final --gpu 0 --save_predictions\\\"\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-21T01:02:37.155Z\", \"training_hours\": 3.72}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --label_only_loss --gpu 0 --seed 123 --output_dir /root/trace-verdict-study/outputs/codellama13b_label_only_seed123_v2 --wandb_project trace-verdict-study --wandb_run_name codellama13b_label_only_seed123_v2 && python eval/evaluate.py --condition full_trace --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --checkpoint_dir /root/trace-verdict-study/outputs/codellama13b_label_only_seed123_v2/final --gpu 0 --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"654451\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_label_only_seed123_v2.log\", \"submitted_at\": \"2026-05-20T21:19:44.345Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 13375.8, \"gpu_hours\": 3.72}, \"pid\": \"654451\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_label_only_seed123_v2.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T01:02:40.132Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T01:02:44.162900+00:00\"}]}, \"metrics\": {\"accuracy\": \"collapsed\", \"eval_loss\": \"nan\", \"train_loss_final\": 0, \"grad_norm_final\": 0, \"entropy\": 0.25, \"note\": \"full collapse identical to seed42 (28.5%), eval never ran due to disk full but collapse confirmed from training metrics\"}}, \"qwen15b_no_trace_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T21:55:15.016Z\", \"updated_at\": \"2026-05-20T22:15:15.854Z\", \"hypothesis\": \"Qwen-1.5B no_trace 第 3 seed：seed42=67.31% vs seed123=75.88% 差 8.57pp，seed42 疑为异常值。seed456 确定 3-seed mean，判断 67.31% 是否 outlier。\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-20T21:55:35.973Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 456 --output_dir /root/trace-verdict-study/outputs/qwen15b_no_trace_seed456 --wandb_project trace-verdict-study --wandb_run_name qwen15b_no_trace_seed456 && python eval/evaluate.py --condition no_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/trace-verdict-study/outputs/qwen15b_no_trace_seed456/final --gpu 0 --save_predictions\\\"\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-20T22:12:44.259Z\", \"training_hours\": 0.29}, \"spec\": {\"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1640, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 456}, \"pid\": \"657684\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_no_trace_seed456.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T22:12:48.771215+00:00\"}]}, \"metrics\": {\"accuracy\": 0.7387, \"fail_f1\": 0.5266, \"pass_f1\": 0.8195, \"eval_loss\": 0.7725, \"train_loss\": 0.2226, \"fail_precision\": 0.544, \"fail_recall\": 0.5103, \"pass_precision\": 0.8096, \"pass_recall\": 0.8296}, \"checkpoint_path\": \"/root/trace-verdict-study/outputs/qwen15b_no_trace_seed456/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T22:15:15.854Z\"}, \"qwen15b_no_trace_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T21:30:56.732Z\", \"updated_at\": \"2026-05-20T21:54:59.519Z\", \"hypothesis\": \"Qwen-1.5B no_trace 加第 2 seed：seed42=67.31% 是 C2 分解的 baseline 端，单 seed 易被质疑为 seed 运气差。seed123 加固 baseline 使分解更 robust。\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-20T21:31:34.186Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/trace-verdict-study/outputs/qwen15b_no_trace_seed123 --wandb_project trace-verdict-study --wandb_run_name qwen15b_no_trace_seed123 && python eval/evaluate.py --condition no_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/trace-verdict-study/outputs/qwen15b_no_trace_seed123/final --gpu 0 --save_predictions\\\"\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-20T21:52:47.650Z\", \"training_hours\": 0.35}, \"spec\": {\"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1640, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 123}, \"pid\": \"655666\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_no_trace_seed123.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T21:52:52.119376+00:00\"}]}, \"metrics\": {\"accuracy\": 0.7588, \"accuracy_ci_lower\": 0.7328, \"accuracy_ci_upper\": 0.7824, \"majority_baseline\": 0.7151, \"lift\": 0.0437, \"pass_precision\": 0.8279, \"pass_recall\": 0.8367, \"pass_f1\": 0.8323, \"fail_precision\": 0.5788, \"fail_recall\": 0.5634, \"fail_f1\": 0.571, \"train_loss\": 0.2221, \"eval_loss\": 0.7838}, \"checkpoint_path\": \"/root/trace-verdict-study/outputs/qwen15b_no_trace_seed123/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T21:54:59.519Z\"}, \"qwen15b_label_only_seed456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T20:17:58.672Z\", \"updated_at\": \"2026-05-20T21:35:38.062Z\", \"hypothesis\": \"Qwen-1.5B label_only 第3 seed 降低 variance：2-seed mean=80.13±1.72% (variance > Qwen-7B 的 1.12%)，第3 seed 使数据与 Qwen-7B 3-seed 可比。\", \"parent\": \"qwen15b_label_only_seed42_v2\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-20T20:18:26.641Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --label_only_loss --gpu 0 --seed 456 --output_dir /root/trace-verdict-study/outputs/qwen15b_label_only_seed456_v2 --wandb_project trace-verdict-study --wandb_run_name qwen15b_label_only_seed456_v2 && python eval/evaluate.py --condition full_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/trace-verdict-study/outputs/qwen15b_label_only_seed456_v2/final --gpu 0 --save_predictions\\\"\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-20T21:13:54.135Z\", \"training_hours\": 0.92}, \"spec\": {\"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1640, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"trace-verdict-study test split (164 samples)\"}, \"pid\": \"651166\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_label_only_seed456_v2.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T21:13:58.818964+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.8252, \"pass_f1\": 0.885, \"fail_f1\": 0.639, \"pass_precision\": 0.837, \"pass_recall\": 0.938, \"fail_precision\": 0.776, \"fail_recall\": 0.543, \"train_loss\": 0.2394, \"eval_loss\": 0.3064, \"majority_baseline\": 0.715}, \"checkpoint_path\": \"/root/trace-verdict-study/outputs/qwen15b_label_only_seed456_v2/final\", \"completed_at\": \"2026-05-20T21:35:38.062Z\"}, \"deepseek_no_trace_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T21:19:12.571Z\", \"updated_at\": \"2026-05-20T21:31:26.419Z\", \"hypothesis\": \"DeepSeek no_trace 只有 1 seed (73.36%)，加第 2 seed 使 baseline 更 robust。no_trace 是所有条件对比的锚点，单 seed baseline 在 rebuttal 中易被质疑。\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-20T21:19:48.734Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/trace-verdict-study/outputs/deepseek_no_trace_seed123 --wandb_project trace-verdict-study --wandb_run_name deepseek_no_trace_seed123 && python eval/evaluate.py --condition no_trace --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --checkpoint_dir /root/trace-verdict-study/outputs/deepseek_no_trace_seed123/final --gpu 0 --save_predictions\\\"\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\"}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/trace-verdict-study/outputs/deepseek_no_trace_seed123 --wandb_project trace-verdict-study --wandb_run_name deepseek_no_trace_seed123 && python eval/evaluate.py --condition no_trace --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --checkpoint_dir /root/trace-verdict-study/outputs/deepseek_no_trace_seed123/final --gpu 0 --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"654604\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_no_trace_seed123.log\", \"submitted_at\": \"2026-05-20T21:19:50.736Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 695.7, \"gpu_hours\": 0.19}, \"pid\": \"654604\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_no_trace_seed123.log\", \"conclusion\": \"killed\", \"checkpoint_path\": \"N/A (killed before completion)\", \"completed_at\": \"2026-05-20T21:31:26.419Z\"}, \"codellama13b_label_only_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:24:00.685Z\", \"updated_at\": \"2026-05-20T21:18:58.996Z\", \"spec\": {\"command\": \"...full_trace --label_only_loss --model_path CodeLlama-13b-Instruct-hf...\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"642747\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_label_only_seed42_v2.log\", \"submitted_at\": \"2026-05-20T17:24:00.283Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1640, \"model_name\": \"CodeLlama-13B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"trace-verdict-study test split (164 samples)\", \"wall_clock_seconds\": 14098.7, \"gpu_hours\": 3.92}, \"hypothesis\": \"CodeLlama-13B label_only (full_trace with label-only loss) 验证 C2 decomposition 跨架构泛化：Qwen-7B label_only=86.22%, DeepSeek label_only=28.5%. CodeLlama 是第 3 个架构数据点。\", \"metrics\": {\"accuracy\": 0.2849, \"accuracy_ci_lower\": 0.2613, \"accuracy_ci_upper\": 0.3084, \"majority_baseline\": 0.7151, \"lift_pp\": -43.03, \"pass_recall\": 0, \"pass_precision\": 0, \"pass_f1\": 0, \"fail_recall\": 1, \"fail_precision\": 0.2849, \"fail_f1\": 0.4434}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_label_only_seed42_v2/final\", \"completed_at\": \"2026-05-20T21:18:58.996Z\"}, \"qwen15b_label_only_seed123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T19:20:03.067Z\", \"updated_at\": \"2026-05-20T20:18:04.354Z\", \"hypothesis\": \"Qwen-1.5B label_only seed123 验证 C2 decomposition 跨 seed 稳定性：seed42=78.9%, 第 2 seed 确认 label formatting 贡献约 11pp (vs no_trace 67.31%)。\", \"parent\": \"qwen15b_label_only_seed42_v2\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-20T19:20:24.443Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --label_only_loss --gpu 0 --seed 123 --output_dir /root/trace-verdict-study/outputs/qwen15b_label_only_seed123_v2 --wandb_project trace-verdict-study --wandb_run_name qwen15b_label_only_seed123_v2 && python eval/evaluate.py --condition full_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/trace-verdict-study/outputs/qwen15b_label_only_seed123_v2/final --gpu 0 --save_predictions\\\"\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-20T20:15:42.280Z\", \"training_hours\": 0.92}, \"spec\": {\"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1640, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 123, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"trace-verdict-study test split (164 samples)\"}, \"pid\": \"648034\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_label_only_seed123_v2.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T20:15:46.560837+00:00\"}]}, \"metrics\": {\"accuracy\": 0.8134, \"accuracy_ci_lower\": 0.7924, \"accuracy_ci_upper\": 0.8345, \"majority_baseline\": 0.7151, \"lift_pp\": 9.83, \"pass_recall\": 0.94, \"pass_precision\": 0.824, \"pass_f1\": 0.878, \"fail_recall\": 0.496, \"fail_precision\": 0.767, \"fail_f1\": 0.602}, \"checkpoint_path\": \"/root/trace-verdict-study/outputs/qwen15b_label_only_seed123_v2/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T20:18:04.354Z\"}, \"qwen15b_label_only_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T17:24:03.330Z\", \"updated_at\": \"2026-05-20T19:18:53.550Z\", \"spec\": {\"command\": \"...full_trace --label_only_loss --model_path Qwen2.5-Coder-1.5B-Instruct...\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"642828\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_label_only_seed42_v2.log\", \"submitted_at\": \"2026-05-20T17:24:02.903Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1640, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"trace-verdict-study test split (164 samples)\", \"wall_clock_seconds\": 6890.6, \"gpu_hours\": 1.91}, \"hypothesis\": \"Qwen-1.5B label_only (full_trace with label-only loss) 验证 C2 decomposition 跨 scale 泛化：Qwen-7B label_only=86.22%, Qwen-1.5B 是同架构不同 scale 的验证点。\", \"metrics\": {\"accuracy\": 0.789, \"accuracy_ci_lower\": 0.766, \"accuracy_ci_upper\": 0.812, \"majority_baseline\": 0.715, \"lift_pp\": 7.4, \"pass_recall\": 0.91, \"pass_precision\": 0.82, \"pass_f1\": 0.86, \"fail_recall\": 0.5, \"fail_precision\": 0.68, \"fail_f1\": 0.57}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/trace-verdict-study/outputs/qwen15b_label_only_seed42_v2/checkpoint-444\", \"completed_at\": \"2026-05-20T19:18:53.550Z\"}, \"qwen15b_ae_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T16:20:46.263Z\", \"updated_at\": \"2026-05-20T17:23:38.815Z\", \"spec\": {\"command\": \"bash -c \\\"...qwen15b_ae_only_seed123...\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"638597\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_ae_only_seed123.log\", \"submitted_at\": \"2026-05-20T16:20:45.493Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1640, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 123, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"trace-verdict-study test split (164 samples)\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_ae_only_seed123/final/\", \"wall_clock_seconds\": 3773.3, \"gpu_hours\": 1.05}, \"hypothesis\": \"Qwen-1.5B ae_only seed123 应 ≥98%（seed42=99.08%），补齐 Table 1 ae_only 行中 Qwen-1.5B 的 2-seed 覆盖\", \"parent\": \"qwen15b_ae_only_seed42\", \"metrics\": {\"accuracy\": 0.9857, \"majority_baseline\": 0.715, \"lift_pp\": 27.1, \"fail_f1\": 0.975}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T17:23:38.815Z\"}, \"deepseek_loop_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T14:55:41.209Z\", \"updated_at\": \"2026-05-20T17:23:37.284Z\", \"spec\": {\"command\": \"bash -c \\\"...deepseek_loop_only_seed456...\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"633962\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_loop_only_seed456.log\", \"submitted_at\": \"2026-05-20T14:55:40.756Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1640, \"model_name\": \"DeepSeek-Coder-6.7B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"trace-verdict-study test split (164 samples)\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_loop_only_seed456/final/\", \"wall_clock_seconds\": 8876.5, \"gpu_hours\": 2.47}, \"hypothesis\": \"DeepSeek loop_only seed456 验证 3-seed 稳定性：当前 seed42=seed123=81.26% (std=0)，reviewer 会质疑。第 3 seed 确认或修正这个异常一致性。\", \"parent\": \"deepseek_loop_only_seed42\", \"metrics\": {\"accuracy\": 0.784, \"majority_baseline\": 0.715, \"lift_pp\": 6.9, \"fail_f1\": 0.63}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T17:23:37.285Z\"}, \"qwen15b_vota_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:23:45.586Z\", \"updated_at\": \"2026-05-20T16:19:33.540Z\", \"spec\": {\"command\": \"bash -c \\\"...qwen15b_vota_seed123...\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"635814\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_vota_seed123.log\", \"submitted_at\": \"2026-05-20T15:23:45.139Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1640, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 123, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"trace-verdict-study test split (164 samples)\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_vota_seed123/final/\", \"wall_clock_seconds\": 3348.4, \"gpu_hours\": 0.93}, \"hypothesis\": \"Qwen-1.5B VOTA seed123 应 ≥98%（seed42=99.58%），补齐 C4 VOTA universality 的 Qwen-1.5B 2-seed 覆盖\", \"parent\": \"qwen15b_vota_seed42\", \"metrics\": {\"accuracy\": 0.995, \"ci_95\": [0.9908, 0.9983], \"pass_f1\": 0.9965, \"fail_f1\": 0.9912, \"lift_pp\": 28, \"n_samples\": 1190}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T16:19:33.540Z\"}, \"deepseek_ae_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T12:46:47.345Z\", \"updated_at\": \"2026-05-20T15:24:01.445Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition ae_only --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_ae_only_seed123 --wandb_project trace-verdict-study --wandb_run_name deepseek_ae_only_seed123 && python eval/evaluate.py --condition ae_only --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_ae_only_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_ae_only_seed123/final/eval_results.json --save_predictions --max_length 2048\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"626709\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_ae_only_seed123.log\", \"submitted_at\": \"2026-05-20T12:46:46.933Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1640, \"model_name\": \"DeepSeek-Coder-6.7B-Instruct\", \"seed\": 123, \"wall_clock_seconds\": 9299.3, \"gpu_hours\": 2.58}, \"hypothesis\": \"Cross-seed validation for ae_only on DeepSeek-6.7B: seed42 achieved 99.08%, seed123 should confirm ae_only's cross-seed robustness on DeepSeek (strengthening C2 ae_only universality claim)\", \"reproduce\": {\"finished_at\": \"2026-05-20T15:17:53.732Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T15:17:57.838508+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9832}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_ae_only_seed123/final/\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_ae_only_seed123.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T15:21:46.249Z\"}, \"qwen15b_loop_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T13:35:56.439Z\", \"updated_at\": \"2026-05-20T14:54:32.548Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition loop_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed456 --wandb_project trace-verdict-study --wandb_run_name qwen15b_loop_only_seed456 && python eval/evaluate.py --condition loop_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed456/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed456/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"630189\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_loop_only_seed456.log\", \"submitted_at\": \"2026-05-20T13:35:55.990Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1640, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"trace-verdict-study test split (164 samples)\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed456/final/\", \"wall_clock_seconds\": 4716.6, \"gpu_hours\": 1.31}, \"hypothesis\": \"Qwen-1.5B loop_only seed456 应在 76-84%（与 seed42=78.32%, seed123=81.09% 接近），补齐 3-seed mean 确认 Tier 2 loop_only 跨种子稳定性\", \"parent\": \"qwen15b_loop_only_seed42\", \"metrics\": {\"accuracy\": 0.792, \"ci_95\": [0.768, 0.813], \"majority_baseline\": 0.715, \"lift_pp\": 7.6, \"pass_precision\": 0.85, \"pass_recall\": 0.86, \"pass_f1\": 0.86, \"fail_precision\": 0.64, \"fail_recall\": 0.62, \"fail_f1\": 0.63}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T14:54:32.548Z\"}, \"codellama13b_loop_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T09:03:02.178Z\", \"updated_at\": \"2026-05-20T13:14:57.428Z\", \"spec\": {\"command\": \"train_sft.py --condition loop_only + evaluate.py\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"609613\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_loop_only_seed456.log\", \"submitted_at\": \"2026-05-20T09:03:01.670Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1190, \"model_name\": \"CodeLlama-13B-Instruct\", \"seed\": 456, \"wall_clock_seconds\": 14064.0, \"gpu_hours\": 3.91}, \"reproduce\": {\"finished_at\": \"2026-05-20T12:53:42.048Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T12:53:45.150978+00:00\"}]}, \"metrics\": {\"accuracy\": 0.7908, \"majority_baseline\": 0.7151, \"lift\": 0.0757, \"pass_precision\": 0.912, \"pass_recall\": 0.783, \"pass_f1\": 0.843, \"fail_precision\": 0.598, \"fail_recall\": 0.811, \"fail_f1\": 0.688, \"n\": 1190}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_loop_only_seed456/final\", \"log_path\": \"/root/runs/trace-verdict-study/codellama13b_loop_only_seed456.log\", \"conclusion\": \"success\", \"hypothesis\": \"CodeLlama-13B loop_only seed456 应在 74-80% 范围（与 seed42=77.06%, seed123=76.05% 接近），验证 Tier 2 loop_only 在 13B scale 的跨 seed 稳定性\", \"completed_at\": \"2026-05-20T12:57:25.720Z\", \"parent\": \"codellama13b_loop_only_seed42\"}, \"qwen15b_exception_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:35:25.949Z\", \"updated_at\": \"2026-05-20T12:56:37.525Z\", \"hypothesis\": \"Qwen-1.5B exception_only seed123 应达 ~99.83%（与 seed42 一致），为 W3 reviewer concern 提供 1.5B scale 的方差估计\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed123 --wandb_project trace-verdict-study --wandb_run_name qwen15b_exception_only_seed123 && python eval/evaluate.py --condition exception_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed123/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"627797\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_exception_only_seed123.log\", \"submitted_at\": \"2026-05-20T12:56:36.946Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"failed\", \"metrics\": {\"error\": \"CUDA OOM at step 3/444\", \"exit_code\": 1, \"cause\": \"GPU 0 had 45.15 GiB PyTorch allocated (likely concurrent model loading with codellama13b), only 1.80 GiB free when trying to allocate 4.64 GiB\", \"seed_comparison\": {\"seed42_accuracy\": 0.9983, \"seed123_accuracy\": \"N/A - OOM crash\"}}, \"completed_at\": \"2026-05-18T21:40:33.694Z\"}, \"qwen15b_loop_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T11:54:39.904Z\", \"updated_at\": \"2026-05-20T12:44:20.419Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition loop_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed123 --wandb_project trace-verdict-study --wandb_run_name qwen15b_loop_only_seed123 && python eval/evaluate.py --condition loop_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed123/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"623714\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_loop_only_seed123.log\", \"submitted_at\": \"2026-05-20T11:54:39.487Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/loop_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 123, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/loop_only_test.jsonl\", \"wall_clock_seconds\": 2980.9, \"gpu_hours\": 0.83}, \"reproduce\": {\"finished_at\": \"2026-05-20T12:40:47.934Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T12:40:50.915806+00:00\"}]}, \"hypothesis\": \"Qwen-1.5B loop_only seed123 应与 seed42 (78.32%) 接近，验证 Tier 2 loop_only 在 1.5B scale 的跨 seed 稳定性\", \"parent\": \"qwen15b_loop_only_seed42\", \"metrics\": {\"accuracy\": 0.8109, \"pass_f1\": 0.8737, \"fail_f1\": 0.6244, \"pass_precision\": 0.8366, \"pass_recall\": 0.9142, \"fail_precision\": 0.7192, \"fail_recall\": 0.5516, \"train_loss\": 0.0843, \"train_runtime_sec\": 2659.73}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed123/final/\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_loop_only_seed123.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T12:44:20.419Z\"}, \"codellama13b_vota_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T03:10:20.719Z\", \"updated_at\": \"2026-05-20T11:35:28.253Z\", \"hypothesis\": \"CodeLlama-13B VOTA seed123 应在 97-100%（与 seed42=98.57% 接近），验证 VOTA Tier 1 跨 seed 稳定性\", \"parent\": \"codellama13b_vota_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && ...\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"601095\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_vota_seed123.log\", \"submitted_at\": \"2026-05-20T07:35:22.845Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/vota_train.jsonl\", \"data_count\": 4720, \"model_name\": \"CodeLlama-13B-Instruct-hf\", \"seed\": 123, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/vota_test.jsonl\", \"wall_clock_seconds\": 14382.3, \"gpu_hours\": 4.0}, \"reproduce\": {\"finished_at\": \"2026-05-20T11:32:16.006Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T11:32:20.242389+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9891, \"accuracy_ci\": [0.9832, 0.9941], \"pass_precision\": 0.9929, \"pass_recall\": 0.9918, \"pass_f1\": 0.9924, \"fail_precision\": 0.9794, \"fail_recall\": 0.9823, \"fail_f1\": 0.9809, \"n\": 1190, \"majority_baseline\": 0.7151, \"lift\": 0.2739}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_vota_seed123/final\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_vota_seed123.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T11:35:05.193Z\"}, \"qwen15b_loop_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T07:51:37.747Z\", \"updated_at\": \"2026-05-20T08:44:07.965Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition loop_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed42 --wandb_project trace-verdict-study --wandb_run_name qwen15b_loop_only_seed42 && python eval/evaluate.py --condition loop_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed42/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"602560\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_loop_only_seed42.log\", \"submitted_at\": \"2026-05-20T07:51:37.348Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/loop_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"wall_clock_seconds\": 3102.7, \"gpu_hours\": 0.86}, \"reproduce\": {\"finished_at\": \"2026-05-20T08:39:30.273Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T08:39:33.542076+00:00\"}]}, \"hypothesis\": \"Qwen-1.5B loop_only 应在 75-85% 范围（与 Qwen-7B 86%/CodeLlama-13B 77%/DeepSeek 81% 对比），验证 Tier 2 loop_only 在最小 scale (1.5B) 的表现，观察 scale 对 Tier 2 信号密度条件的影响\", \"metrics\": {\"accuracy\": 0.7832, \"pass_f1\": 0.8526, \"fail_f1\": 0.5905, \"pass_precision\": 0.8298, \"pass_recall\": 0.8766, \"fail_precision\": 0.6392, \"fail_recall\": 0.5487, \"train_loss\": 0.0847, \"train_runtime_sec\": 2679}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_loop_only_seed42/final/\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_loop_only_seed42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T08:43:20.070Z\"}, \"qwen15b_ae_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T06:52:17.793Z\", \"updated_at\": \"2026-05-20T07:50:58.882Z\", \"hypothesis\": \"Qwen-1.5B ae_only 应达 ≥95% accuracy，与 Qwen-7B (99.92%) / CodeLlama-13B (99.08%) / DeepSeek (98.74%) 一致，验证 Tier 1 ae_only 在最小 scale (1.5B) 仍然有效\", \"parent\": \"qwen15b_exception_only_seed42\", \"spec\": {\"command\": \"bash -c \\\"...qwen15b_ae_only_seed42...\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"598258\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_ae_only_seed42.log\", \"submitted_at\": \"2026-05-20T06:52:39.041Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/ae_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/ae_only_test.jsonl\", \"wall_clock_seconds\": 3499.8, \"gpu_hours\": 0.97}, \"reproduce\": {\"finished_at\": \"2026-05-20T07:46:34.828Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T07:46:39.544624+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9908, \"majority_baseline\": 0.7151, \"lift\": 0.2756, \"pass_precision\": 1, \"pass_recall\": 0.987, \"pass_f1\": 0.9935, \"fail_precision\": 0.9686, \"fail_recall\": 1, \"fail_f1\": 0.984, \"n\": 1190, \"accuracy_ci_lower\": 0.9849, \"accuracy_ci_upper\": 0.9958}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_ae_only_seed42/final/\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_ae_only_seed42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T07:50:58.882Z\"}, \"codellama13b_ae_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T03:04:54.397Z\", \"updated_at\": \"2026-05-20T07:33:40.315Z\", \"hypothesis\": \"CodeLlama-13B ae_only seed123 应在 98-100% 范围（与 seed42=99.08% 接近），验证 Tier 1 ae_only 跨 seed 稳定性（rebuttal 储备）\", \"parent\": \"codellama13b_ae_only_seed42\", \"spec\": {\"command\": \"bash -c \\\"...codellama13b_ae_only_seed123...\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"583496\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_ae_only_seed123.log\", \"submitted_at\": \"2026-05-20T03:05:13.102Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/ae_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"codellama/CodeLlama-13b-Instruct-hf\", \"seed\": 123, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/ae_only_test.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_ae_only_seed123/final\", \"wall_clock_seconds\": 15624.3, \"gpu_hours\": 4.34}, \"reproduce\": {\"finished_at\": \"2026-05-20T07:31:03.573Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T07:31:08.333919+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9908, \"accuracy_ci_lower\": 0.9849, \"accuracy_ci_upper\": 0.9958, \"pass_precision\": 1, \"pass_recall\": 0.987, \"pass_f1\": 0.993, \"fail_precision\": 0.969, \"fail_recall\": 1, \"fail_f1\": 0.984, \"train_loss\": 0.0592, \"train_runtime_sec\": 15624, \"gpu_hours\": 4.34}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T07:33:40.315Z\"}, \"deepseek_exception_only_seed123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T04:59:58.895Z\", \"updated_at\": \"2026-05-20T06:51:44.480Z\", \"hypothesis\": \"DeepSeek exception_only seed123 在当前代码下应 ≥98%（与 seed42=99.33% 接近），验证 5/15 的 91.09% 是否为代码旧版本导致\", \"parent\": \"deepseek_exception_only_seed42\", \"spec\": {\"command\": \"bash -c \\\"...deepseek_exception_only_seed123_v2...\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"591985\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_exception_only_seed123_v2.log\", \"submitted_at\": \"2026-05-20T05:00:15.656Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 123, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_test.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_exception_only_seed123_v2/final/\", \"wall_clock_seconds\": 6669.2, \"gpu_hours\": 1.85}, \"reproduce\": {\"finished_at\": \"2026-05-20T06:47:54.611Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T06:47:59.099687+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.995}, \"completed_at\": \"2026-05-20T06:51:24.856Z\"}, \"deepseek_vota_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T02:35:59.967Z\", \"updated_at\": \"2026-05-20T04:58:10.410Z\", \"hypothesis\": \"DeepSeek VOTA seed456 第 3 seed 仲裁：seed42=84.45% vs seed123=99.16% 差距 14.71pp。若 seed456 ∈ [95%, 100%] 则 seed42 是 outlier，DeepSeek VOTA 归 Tier 1；若 ∈ [82%, 88%] 则 VOTA 在 DeepSeek 上高方差，需重新评估 Tier 归属\", \"parent\": \"deepseek_vota_seed123\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota_seed456 --gradient_checkpointing --gpu 0 --seed 456 --wandb_project trace-verdict-study --wandb_run_name deepseek_vota_seed456 && python eval/evaluate.py --condition vota --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota_seed456/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota_seed456/final/eval_results.json --save_predictions --max_length 2048\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"579517\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_vota_seed456.log\", \"submitted_at\": \"2026-05-20T02:36:17.947Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/vota_train.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 456, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/vota_test.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota_seed456/final\", \"wall_clock_seconds\": 8512.5, \"gpu_hours\": 2.36}, \"reproduce\": {\"finished_at\": \"2026-05-20T04:55:18.779Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T04:55:23.587676+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9933}, \"completed_at\": \"2026-05-20T04:58:10.410Z\"}, \"codellama13b_no_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-16T07:47:20.182Z\", \"updated_at\": \"2026-05-20T03:09:12.228Z\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_no_trace_seed42 --wandb_project trace-verdict-study --wandb_run_name codellama13b_no_trace_seed42 && python eval/evaluate.py --condition no_trace --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_no_trace_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_no_trace_seed42/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"codellama13b_no_trace_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T14:19:42.177Z\"}, \"gpu_ids\": [\"cuda:1\"], \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T14:19:44.574583+00:00\"}], \"previous_failure\": {\"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.765, \"n\": 1190, \"majority_baseline\": 0.7151, \"lift\": 0.05, \"pass_precision\": 0.84, \"pass_recall\": 0.83, \"pass_f1\": 0.84, \"fail_precision\": 0.59, \"fail_recall\": 0.59, \"fail_f1\": 0.59, \"accuracy_ci\": [0.738, 0.787]}}}, \"completed_at\": \"2026-05-16T14:22:58.643Z\", \"hypothesis\": \"CodeLlama-13B no-trace baseline: without execution trace, larger model capacity does not compensate for missing diagnostic signal — accuracy near majority baseline as on smaller models\", \"parent\": \"no_trace_seed42_v5\", \"spec\": {\"command\": \"previously completed\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/no_trace_train.jsonl\", \"data_count\": 4720, \"model_name\": \"codellama/CodeLlama-13b-Instruct-hf\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_no_trace_seed42/final\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_no_trace_seed42.log\", \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/no_trace_test.jsonl\"}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.765, \"n\": 1190, \"majority_baseline\": 0.7151, \"lift\": 0.05, \"pass_precision\": 0.84, \"pass_recall\": 0.83, \"pass_f1\": 0.84, \"fail_precision\": 0.59, \"fail_recall\": 0.59, \"fail_f1\": 0.59, \"accuracy_ci_lower\": 0.738, \"accuracy_ci_upper\": 0.787}}, \"codellama13b_loop_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T23:10:32.075Z\", \"updated_at\": \"2026-05-20T03:04:16.177Z\", \"hypothesis\": \"CodeLlama-13B loop_only seed123 应在 74-80% 范围（与 seed42=77.06% 接近），验证 Tier 2 collapse（≈no_trace）是否 seed-robust，CodeLlama 是唯一 Tier 2 failed 的模型\", \"parent\": \"codellama13b_loop_only_seed42\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"...codellama13b_loop_only_seed123...\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"543506\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_loop_only_seed123.log\", \"submitted_at\": \"2026-05-19T23:10:51.377Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/loop_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"codellama/CodeLlama-13b-Instruct-hf\", \"seed\": 123, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/loop_only_test.jsonl\", \"wall_clock_seconds\": 14004.8, \"gpu_hours\": 3.89}, \"reproduce\": {\"finished_at\": \"2026-05-20T03:02:44.274Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T03:02:51.934438+00:00\"}]}, \"metrics\": {\"accuracy\": 0.7605, \"accuracy_ci_lower\": 0.7387, \"accuracy_ci_upper\": 0.7857, \"pass_precision\": 0.9478, \"pass_recall\": 0.7039, \"pass_f1\": 0.8078, \"fail_precision\": 0.5484, \"fail_recall\": 0.9027, \"fail_f1\": 0.6823, \"majority_baseline\": 0.7151, \"lift\": 0.0454, \"n\": 1190}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_loop_only_seed123/final\", \"completed_at\": \"2026-05-20T03:04:16.177Z\"}, \"deepseek_vota_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T00:13:27.141Z\", \"updated_at\": \"2026-05-20T02:38:03.290Z\", \"hypothesis\": \"DeepSeek VOTA seed123 accuracy ∈ [82%, 88%]，验证 seed42=84.45% 的稳定性，补充 VOTA 跨 seed robustness 证据（rebuttal 储备）\", \"parent\": \"deepseek_vota_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota_seed123 --gradient_checkpointing --gpu 0 --seed 123 --wandb_project trace-verdict-study --wandb_run_name deepseek_vota_seed123 && python eval/evaluate.py --condition vota --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota_seed123/final/eval_results.json --save_predictions --max_length 2048\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"553506\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_vota_seed123.log\", \"submitted_at\": \"2026-05-20T00:13:45.484Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/vota_train.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 123, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/vota_test.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota_seed123/final\", \"wall_clock_seconds\": 8533.1, \"gpu_hours\": 2.37}, \"reproduce\": {\"finished_at\": \"2026-05-20T02:33:53.965Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T02:33:58.617133+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9916, \"accuracy_ci_lower\": 0.9857, \"accuracy_ci_upper\": 0.9966, \"fail_recall\": 0.973, \"pass_recall\": 0.999, \"train_loss\": 0.0625, \"eval_loss\": 0.11}, \"completed_at\": \"2026-05-20T02:35:58.540Z\"}, \"deepseek_loop_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:38:49.036Z\", \"updated_at\": \"2026-05-20T00:14:38.720Z\", \"hypothesis\": \"DeepSeek-6.7B loop_only seed123 应在 78-84% 范围（与 seed42=81.26% 接近），验证 Tier 2 跨 seed 稳定性，补充 reviewer single-seed concern\", \"parent\": \"deepseek_loop_only_seed42\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition loop_only --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_loop_only_seed123 --wandb_project trace-verdict-study --wandb_run_name deepseek_loop_only_seed123 && python eval/evaluate.py --condition loop_only --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_loop_only_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_loop_only_seed123/final/eval_results.json --save_predictions --max_length 2048\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"538294\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_loop_only_seed123.log\", \"submitted_at\": \"2026-05-19T21:39:34.717Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/loop_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 123, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/loop_only_test.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_loop_only_seed123/final\", \"wall_clock_seconds\": 9221.4, \"gpu_hours\": 2.56}, \"reproduce\": {\"finished_at\": \"2026-05-20T00:10:53.831Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T00:10:57.808157+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.8126, \"accuracy_ci_lower\": 0.792, \"accuracy_ci_upper\": 0.834, \"pass_recall\": 0.856, \"fail_recall\": 0.705}, \"completed_at\": \"2026-05-20T00:13:16.133Z\"}, \"cross_model_calibration_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T21:40:43.958Z\", \"updated_at\": \"2026-05-19T21:41:10.724Z\", \"hypothesis\": \"4 模型 × exception_only 的 ECE/Brier 应一致性低（ECE < 0.01），验证 calibration quality 跨模型 universal\", \"conclusion\": \"success\", \"metrics\": {\"qwen_7b\": {\"ece\": 0.0027, \"mce\": 0.8355, \"brier\": 0.0013, \"accuracy\": 0.9983}, \"qwen_1_5b\": {\"ece\": 0.002, \"mce\": 0.7549, \"brier\": 0.0013, \"accuracy\": 0.9983}, \"codellama_13b\": {\"ece\": 0.002, \"mce\": 0.0411, \"brier\": 0.0013, \"accuracy\": 0.9983}, \"deepseek_6_7b\": {\"ece\": 0.0064, \"mce\": 0.7756, \"brier\": 0.0061, \"accuracy\": 0.9933}}, \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/cross_model_calibration_results.json\", \"log_path\": \"N/A - eval only\", \"server\": \"westd-11235\", \"data_path\": \"existing exception_only checkpoints x4\", \"data_count\": 1190, \"model_name\": \"4 models x exception_only\", \"seed\": 42}, \"completed_at\": \"2026-05-19T21:41:10.724Z\"}, \"codellama13b_vota_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:47:21.632Z\", \"updated_at\": \"2026-05-19T21:37:28.024Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_vota_seed42 --wandb_project trace-verdict-study --wandb_run_name codellama13b_vota_seed42 && python eval/evaluate.py --condition vota --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_vota_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_vota_seed42/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"279473\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_vota_seed42.log\", \"submitted_at\": \"2026-05-16T14:23:09.712Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14537.8, \"gpu_hours\": 4.04}, \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"279473\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_vota_seed42.log\", \"wandb_run_id\": \"codellama13b_vota_seed42\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_vota_seed42 --wandb_project trace-verdict-study --wandb_run_name codellama13b_vota_seed42 && python eval/evaluate.py --condition vota --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_vota_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_vota_seed42/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"codellama13b_vota_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T18:21:13.833Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T18:21:16.129637+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9857, \"accuracy_ci_lower\": 0.979, \"accuracy_ci_upper\": 0.9916, \"pass_f1\": 0.99, \"fail_f1\": 0.9748, \"n_test\": 1190}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_vota_seed42/final\", \"completed_at\": \"2026-05-16T18:25:27.552Z\", \"hypothesis\": \"CodeLlama-13B VOTA accuracy 应在 85-92%，与 Qwen-7B VOTA (~99%) 对比，验证 VOTA 压缩方法跨模型有效性（rebuttal 储备：reviewer 追问 VOTA cross-model generalization）\", \"parent\": \"vota_seed42_v5\"}, \"deepseek_label_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T17:52:51.095Z\", \"updated_at\": \"2026-05-19T21:34:38.836Z\", \"hypothesis\": \"DeepSeek-6.7B full_trace + label_only_loss 应显著高于标准 full_trace (79.16%)，预期 82-88%，跨模型验证 gradient dilution 是 full_trace collapse 的主因（26%/74% 分解），回应 Claim 2 跨模型泛化\", \"parent\": \"deepseek_full_trace_seed42_v3\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --gradient_checkpointing --label_only_loss --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_label_only_seed42 --wandb_project trace-verdict-study --wandb_run_name deepseek_label_only_seed42 && python eval/evaluate.py --condition full_trace --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_label_only_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_label_only_seed42/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"530290\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_label_only_seed42.log\", \"submitted_at\": \"2026-05-19T18:53:38.289Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_train.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 42, \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_test.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_label_only_seed42/final\", \"wall_clock_seconds\": 9660.5, \"gpu_hours\": 2.68}, \"reproduce\": {\"finished_at\": \"2026-05-19T21:14:38.257Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T21:14:42.796371+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"accuracy\": 0.285, \"accuracy_ci_lower\": 0.261, \"accuracy_ci_upper\": 0.308, \"majority_baseline\": 0.7151, \"lift\": -0.43, \"pass_precision\": 0, \"pass_recall\": 0, \"pass_f1\": 0, \"fail_precision\": 0.28, \"fail_recall\": 1, \"fail_f1\": 0.44, \"train_loss\": 1.7839, \"eval_loss\": \"nan\"}, \"completed_at\": \"2026-05-19T21:34:38.836Z\"}, \"codellama13b_loop_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:59:26.886Z\", \"updated_at\": \"2026-05-19T18:55:37.408Z\", \"hypothesis\": \"CodeLlama-13B loop_only 应显著低于 ae_only（预期差距≥10pp），验证 Tier hierarchy（ae_only > loop_only）在非 Qwen 架构上成立，回应 Round 9 MF2 跨模型验证要求\", \"parent\": \"vota_loop_only_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition loop_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_loop_only_seed42 --wandb_project trace-verdict-study --wandb_run_name codellama13b_loop_only_seed42 && python eval/evaluate.py --condition loop_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_loop_only_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_loop_only_seed42/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"517765\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_loop_only_seed42.log\", \"submitted_at\": \"2026-05-19T15:00:28.260Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14090.4, \"gpu_hours\": 3.91}, \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"517765\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_loop_only_seed42.log\", \"wandb_run_id\": \"codellama13b_loop_only_seed42\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition loop_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_loop_only_seed42 --wandb_project trace-verdict-study --wandb_run_name codellama13b_loop_only_seed42 && python eval/evaluate.py --condition loop_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_loop_only_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_loop_only_seed42/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"codellama13b_loop_only_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-19T18:51:05.347Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T18:51:09.241877+00:00\"}]}, \"metrics\": {\"accuracy\": 0.7706, \"accuracy_ci_lower\": 0.7487, \"accuracy_ci_upper\": 0.7941, \"n\": 1190, \"majority_baseline\": 0.7151, \"lift\": 0.0555, \"fail_recall\": 0.826, \"pass_recall\": 0.7485, \"pass_precision\": 0.92, \"fail_precision\": 0.57, \"pass_f1\": 0.82, \"fail_f1\": 0.67}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_loop_only_seed42/final\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T18:55:18.642Z\"}, \"qwen7b_full_trace_tail512_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-18T15:37:57.803Z\", \"updated_at\": \"2026-05-19T14:26:10.097Z\", \"hypothesis\": \"Qwen-7B tail-512 (硬截断 full_trace_tail_512) 应与原 full_trace_tail seed42 结果 (~93.6%) 接近，确认 condition 差异不影响 budget curve 结论；同时为 cross-seed 提供可比 baseline\", \"parent\": \"full_trace_tail_seed42\", \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-19T13:09:55.237Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T14:26:11.468840+00:00\"}]}, \"spec\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail_512 --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --seed 42 --gradient_checkpointing --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_tail512_seed42/ --wandb_project trace-verdict-study --wandb_run_name qwen7b_full_trace_tail512_seed42 && /root/miniconda3/bin/python eval/evaluate.py --condition full_trace_tail_512 --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_tail512_seed42/final --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --save_predictions\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_tail512_seed42/final\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T14:26:06.191Z\"}, \"conclusion\": \"failed\"}, \"qwen1.5b_full_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:27:39.587Z\", \"updated_at\": \"2026-05-19T12:52:36.469Z\", \"spec\": {\"hypothesis\": \"Multi-scale validation: full_trace on Qwen-2.5-Coder-1.5B.\", \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"condition\": \"full_trace\"}, \"conclusion\": \"killed\", \"failure_reason\": \"replaced by qwen15b_* entries (dot in exp_id incompatible with submit_on_allocated)\", \"hypothesis\": \"Qwen-1.5B full_trace 应达 ≥96% accuracy，确认 1.5B 小模型在 full trace 条件下与 7B 可比（trace quality 主导而非 model capacity）\", \"notes\": \"重复条目，已在 qwen15b_full_trace_seed42 (77.06%) 完成。命名差异：qwen1.5b_ → qwen15b_\"}, \"codellama_no_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:27:42.805Z\", \"updated_at\": \"2026-05-19T12:52:35.073Z\", \"spec\": {\"hypothesis\": \"Multi-family baseline: no_trace on CodeLlama-7B-Instruct.\", \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 42, \"condition\": \"no_trace\"}, \"conclusion\": \"killed\", \"failure_reason\": \"user approved 13B not 7B\", \"hypothesis\": \"CodeLlama-13B no_trace 应在 70-78% (≈majority baseline)，确认无 trace 时 13B scale 无法补偿信息缺失\", \"notes\": \"重复条目，已在 codellama13b_no_trace_seed42 (76.5%) 完成。命名差异：codellama_ → codellama13b_\"}, \"qwen1.5b_vota_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:27:38.134Z\", \"updated_at\": \"2026-05-19T12:52:04.641Z\", \"spec\": {\"hypothesis\": \"Multi-scale validation: VOTA on Qwen-2.5-Coder-1.5B.\", \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"condition\": \"vota\"}, \"conclusion\": \"killed\", \"failure_reason\": \"replaced by qwen15b_* entries (dot in exp_id incompatible with submit_on_allocated)\", \"hypothesis\": \"Qwen-1.5B VOTA 应在 82-90% accuracy，可能略低于 7B 因 VOTA 条件下 scale-sensitivity 更明显\", \"notes\": \"重复条目，已在 qwen15b_vota_seed42 (99.58%) 完成。命名差异：qwen1.5b_ → qwen15b_\"}, \"codellama_vota_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:27:43.769Z\", \"updated_at\": \"2026-05-19T12:52:03.704Z\", \"spec\": {\"hypothesis\": \"Multi-family validation: VOTA on CodeLlama-7B-Instruct.\", \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 42, \"condition\": \"vota\"}, \"conclusion\": \"killed\", \"failure_reason\": \"user approved 13B not 7B\", \"hypothesis\": \"CodeLlama-13B VOTA 应在 85-92% accuracy，与 Qwen-7B/DeepSeek VOTA 对齐，作 rebuttal 储备验证 ablation condition 跨 scale 一致性\", \"notes\": \"重复条目，已在 codellama13b_vota_seed42 (98.57%) 完成。命名差异：codellama_ → codellama13b_\"}, \"qwen1.5b_exception_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:27:34.741Z\", \"updated_at\": \"2026-05-19T12:51:38.800Z\", \"spec\": {\"hypothesis\": \"Multi-scale validation: exception_only on Qwen-2.5-Coder-1.5B. Tests if exception dominance holds at smaller scale.\", \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"condition\": \"exception_only\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\"}, \"conclusion\": \"killed\", \"failure_reason\": \"replaced by qwen15b_* entries (dot in exp_id incompatible with submit_on_allocated)\", \"hypothesis\": \"Qwen-1.5B exception_only 应达 ≥99% accuracy，确认 minimal sufficient signal 在 1.5B scale 有效，signal quality 主导 model capacity\", \"notes\": \"重复条目，已在 qwen15b_exception_only_seed42 (99.83%) 完成。命名差异：qwen1.5b_ → qwen15b_\"}, \"qwen7b_full_trace_label_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T05:39:47.245Z\", \"updated_at\": \"2026-05-19T11:39:34.147Z\", \"hypothesis\": \"Qwen-7B full_trace (label_only_loss) seed456 应在 95-98% 范围（与 seed42 一致），为 N5 reviewer concern 提供 full_trace 条件的方差估计\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --seed 456 --gradient_checkpointing --label_only_loss --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_label_only_seed456/ --wandb_project trace-verdict-study --wandb_run_name qwen7b_full_trace_label_only_seed456 && /root/miniconda3/bin/python eval/evaluate.py --condition full_trace --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_label_only_seed456/final --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"501315\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_full_trace_label_only_seed456.log\", \"submitted_at\": \"2026-05-19T09:05:27.608Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"wall_clock_seconds\": 9246.5, \"gpu_hours\": 2.57}, \"reproduce\": {\"finished_at\": \"2026-05-19T11:36:54.329Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T11:36:58.222319+00:00\"}]}, \"metrics\": {\"accuracy\": 0.847, \"accuracy_ci_lower\": 0.827, \"accuracy_ci_upper\": 0.866, \"pass_f1\": 0.9, \"fail_f1\": 0.71, \"pass_precision\": 0.87, \"pass_recall\": 0.92, \"fail_precision\": 0.76, \"fail_recall\": 0.67, \"majority_baseline\": 0.7151, \"lift\": 0.1319, \"train_loss\": 0.2452, \"eval_loss\": 0.3366}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_label_only_seed456/final\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_full_trace_label_only_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:39:34.147Z\"}, \"qwen7b_full_trace_label_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T05:39:45.764Z\", \"updated_at\": \"2026-05-19T11:23:36.307Z\", \"hypothesis\": \"Qwen-7B full_trace (label_only_loss) seed123 应在 95-98% 范围（与 seed42 一致），为 N5 reviewer concern 提供 full_trace 条件的方差估计\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --seed 123 --gradient_checkpointing --label_only_loss --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_label_only_seed123/ --wandb_project trace-verdict-study --wandb_run_name qwen7b_full_trace_label_only_seed123 && /root/miniconda3/bin/python eval/evaluate.py --condition full_trace --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_label_only_seed123/final --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"499561\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_full_trace_label_only_seed123.log\", \"submitted_at\": \"2026-05-19T08:38:38.356Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 123, \"wall_clock_seconds\": 9898.0, \"gpu_hours\": 2.75}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.8689, \"accuracy_ci_lower\": 0.8496, \"accuracy_ci_upper\": 0.8874, \"pass_f1\": 0.9121, \"fail_f1\": 0.7426, \"pass_precision\": 0.8765, \"pass_recall\": 0.9506, \"fail_precision\": 0.8427, \"fail_recall\": 0.6637, \"majority_baseline\": 0.7151, \"lift\": 0.1538, \"train_loss\": 0.2425, \"eval_loss\": 0.2787}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_label_only_seed123/final\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_full_trace_label_only_seed123.log\", \"completed_at\": \"2026-05-19T11:23:36.307Z\"}, \"qwen7b_vota_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T05:39:43.207Z\", \"updated_at\": \"2026-05-19T09:06:16.721Z\", \"hypothesis\": \"Qwen-7B VOTA seed456 应在 84-92% 范围（与 vota_seed42_v4 一致），为 N5 reviewer concern 提供 VOTA 条件的方差估计\", \"spec\": {\"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition vota --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --seed 456 --gradient_checkpointing --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_vota_seed456/ --wandb_project trace-verdict-study --wandb_run_name qwen7b_vota_seed456 && /root/miniconda3/bin/python eval/evaluate.py --condition vota --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_vota_seed456/final --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"pid\": \"494086\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T09:02:56.001Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T09:03:00.101888+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9908, \"accuracy_ci_lower\": 0.9849, \"accuracy_ci_upper\": 0.9958, \"majority_baseline\": 0.7151, \"lift\": 0.2756, \"n\": 1190, \"pass_precision\": 1, \"pass_recall\": 0.9871, \"pass_f1\": 0.9935, \"fail_precision\": 0.9686, \"fail_recall\": 1, \"fail_f1\": 0.984, \"train_loss\": 0.04969, \"eval_loss\": 0.08312}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_vota_seed456/final\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_vota_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T09:06:16.721Z\"}, \"qwen7b_vota_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T05:39:41.038Z\", \"updated_at\": \"2026-05-19T08:37:58.799Z\", \"hypothesis\": \"Qwen-7B VOTA seed123 应在 84-92% 范围（与 vota_seed42_v4 一致），为 N5 reviewer concern 提供 VOTA 条件的方差估计\", \"spec\": {\"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 123, \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"account\": \"root\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition vota --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --seed 123 --gradient_checkpointing --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_vota_seed123/ --wandb_project trace-verdict-study --wandb_run_name qwen7b_vota_seed123 && /root/miniconda3/bin/python eval/evaluate.py --condition vota --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_vota_seed123/final --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --save_predictions\\\"\", \"pid\": \"492009\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T08:27:29.961Z\"}, \"failure_reason\": \"N/A - EXIT_CODE=129 was SIGHUP after training+eval had already completed successfully\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T08:27:32.267Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T08:27:35.533591+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9866, \"accuracy_ci_lower\": 0.979, \"accuracy_ci_upper\": 0.9925, \"majority_baseline\": 0.7151, \"lift\": 0.2714, \"n\": 1190, \"pass_precision\": 1, \"pass_recall\": 0.9812, \"pass_f1\": 0.9905, \"fail_precision\": 0.9549, \"fail_recall\": 1, \"fail_f1\": 0.9769, \"train_loss\": 0.0499, \"eval_loss\": 0.0864}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_vota_seed123/final\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_vota_seed123.log\"}, \"qwen7b_full_trace_dynamics_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T03:21:30.436Z\", \"updated_at\": \"2026-05-19T07:03:18.865Z\", \"hypothesis\": \"full_trace (label_only_loss) 收敛速度应慢于 exception_only，因 trace 中冗余信息稀释了有效 signal density。通过每 50 steps eval 记录 learning curve 验证。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --seed 42 --gradient_checkpointing --label_only_loss --save_steps 50 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_dynamics_seed42/ --wandb_project trace-verdict-study --wandb_run_name qwen7b_full_trace_dynamics_seed42 && echo '=== Training done, starting batch eval ===' && /root/miniconda3/bin/python eval/batch_eval_dynamics.py --checkpoint_root /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_dynamics_seed42/ --condition full_trace && echo '=== Batch eval done, cleaning checkpoints ===' && find /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_dynamics_seed42/ -maxdepth 1 -name 'checkpoint-*' -type d -exec rm -rf {} + && echo '=== All done ==='\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"485337\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_full_trace_dynamics_seed42.log\", \"submitted_at\": \"2026-05-19T03:27:23.137Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"wall_clock_seconds\": 12955.7, \"gpu_hours\": 3.6}, \"reproduce\": {\"finished_at\": \"2026-05-19T06:38:01.305Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T06:38:05.031265+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"step50_acc\": 0.8739, \"step100_acc\": 0.821, \"step150_acc\": 0.8571, \"step200_acc\": 0.8655, \"step250_acc\": 0.8739, \"step300_acc\": 0.8487, \"step350_acc\": 0.8882, \"step400_acc\": 0.8571, \"step444_acc\": 0.8824, \"best_step\": 350, \"best_acc\": 0.8882, \"final_loss\": 0.0085}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_dynamics_seed42/final\", \"completed_at\": \"2026-05-19T07:03:18.865Z\"}, \"qwen15b_exception_only_seed123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T21:41:35.811Z\", \"updated_at\": \"2026-05-19T06:40:43.424Z\", \"hypothesis\": \"Qwen-1.5B exception_only seed123 应达 ~99.83%（与 seed42 一致），为 W3 reviewer concern 提供 1.5B scale 的方差估计。v1 因 GPU 并发 OOM 失败，重试。\", \"parent\": \"qwen15b_exception_only_seed123\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition exception_only --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --seed 123 --gradient_checkpointing --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed123_v2/ --wandb_project trace-verdict-study --wandb_run_name qwen15b_exception_only_seed123_v2 && /root/miniconda3/bin/python eval/evaluate.py --condition exception_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed123_v2/final --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"473720\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_exception_only_seed123_v2.log\", \"submitted_at\": \"2026-05-18T23:09:41.499Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 27061.9, \"gpu_hours\": 7.52}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9983, \"accuracy_ci_lower\": 0.9958, \"accuracy_ci_upper\": 1, \"seed_comparison\": {\"seed42_accuracy\": 0.9983, \"seed456_accuracy\": 0.9983, \"seed123_accuracy\": 0.9983}}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed123_v2/final\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_exception_only_seed123_v2.log\", \"completed_at\": \"2026-05-19T06:40:43.424Z\"}, \"qwen7b_exception_only_dynamics_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T03:21:29.197Z\", \"updated_at\": \"2026-05-19T06:00:52.469Z\", \"hypothesis\": \"exception_only 因 information density 更高，收敛速度应显著快于 full_trace（即使 full_trace 用 label_only_loss）。通过每 50 steps eval 记录 learning curve 验证。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition exception_only --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --seed 42 --gradient_checkpointing --save_steps 50 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_exception_only_dynamics_seed42/ --wandb_project trace-verdict-study --wandb_run_name qwen7b_exception_only_dynamics_seed42 && echo '=== Training done, starting batch eval ===' && /root/miniconda3/bin/python eval/batch_eval_dynamics.py --checkpoint_root /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_exception_only_dynamics_seed42/ --condition exception_only && echo '=== Batch eval done, cleaning checkpoints ===' && find /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_exception_only_dynamics_seed42/ -maxdepth 1 -name 'checkpoint-*' -type d -exec rm -rf {} + && echo '=== All done ==='\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"485193\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_exception_only_dynamics_seed42.log\", \"submitted_at\": \"2026-05-19T03:27:19.569Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"wall_clock_seconds\": 9212.9, \"gpu_hours\": 2.56}, \"conclusion\": \"success\", \"metrics\": {\"step50_acc\": 0.9933, \"step100_acc\": 0.9933, \"step150_acc\": 0.9933, \"step200_acc\": 0.9983, \"step250_acc\": 0.9983, \"step300_acc\": 0.9983, \"step350_acc\": 0.9983, \"step400_acc\": 0.9983, \"step444_acc\": 0.9983, \"saturation_step\": 200, \"final_loss\": 0.0329, \"pass_f1\": 0.9988, \"fail_f1\": 0.9971}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_exception_only_dynamics_seed42/final\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_exception_only_dynamics_seed42.log\", \"completed_at\": \"2026-05-19T06:00:52.469Z\"}, \"codellama13b_full_trace_tail512_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T23:20:23.098Z\", \"updated_at\": \"2026-05-19T02:30:30.373Z\", \"hypothesis\": \"CodeLlama-13B tail-512 应在 93-96% 范围，与其他 3 模型 tail-512 收敛带一致，确认 phase transition 阈值跨 4 模型 universal\", \"parent\": \"codellama13b_exception_only_seed42\", \"reproduce\": {\"finished_at\": \"2026-05-18T01:13:45.920Z\"}, \"extra\": {\"seed_comparison\": {\"seed42\": 0.9824, \"seed123\": 0.9824, \"seed456\": 0.9824}}, \"completed_at\": \"2026-05-18T01:35:11.577Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail_512 --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf/ --seed 42 --gradient_checkpointing --label_only_loss --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail512_seed42/ --wandb_project trace-verdict-study --wandb_run_name codellama13b_full_trace_tail512_seed42 && /root/miniconda3/bin/python eval/evaluate.py --condition full_trace_tail_512 --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail512_seed42/final --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf/ --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"476956\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail512_seed42/\", \"submitted_at\": \"2026-05-19T00:11:39.795Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail512_seed42/final\", \"wall_clock_seconds\": 8329.2, \"gpu_hours\": 2.31}, \"metrics\": {\"accuracy\": 0.9824, \"accuracy_ci_lower\": 0.9748, \"accuracy_ci_upper\": 0.9899, \"majority_baseline\": 0.7151, \"lift\": 0.2672, \"n\": 1190, \"pass_precision\": 0.9759, \"pass_recall\": 1, \"pass_f1\": 0.9878, \"fail_precision\": 1, \"fail_recall\": 0.9381, \"fail_f1\": 0.968}, \"conclusion\": \"success\"}, \"codellama13b_full_trace_tail512_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:30:05.472Z\", \"updated_at\": \"2026-05-19T01:34:01.229Z\", \"hypothesis\": \"CodeLlama-13B tail-512 seed456 (label_only_loss) 应在 93-97% range（与 seed42 一致），验证 phase transition 后 convergence band 的 seed robustness 跨架构成立\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail512_seed456/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail512_seed456/\"}, \"metrics\": {\"accuracy\": 0.9824, \"accuracy_ci_lower\": 0.9748, \"accuracy_ci_upper\": 0.9899, \"majority_baseline\": 0.7151, \"lift\": 0.2672, \"n\": 1190, \"pass_precision\": 0.9759, \"pass_recall\": 1, \"pass_f1\": 0.9878, \"fail_precision\": 1, \"fail_recall\": 0.9381, \"fail_f1\": 0.968, \"seed_comparison\": {\"seed42_previous\": 0.975, \"seed123_accuracy\": 0.9824, \"seed456_accuracy\": 0.9824}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T01:33:54.360Z\"}, \"codellama13b_full_trace_tail512_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:30:04.091Z\", \"updated_at\": \"2026-05-18T23:09:01.135Z\", \"hypothesis\": \"CodeLlama-13B tail-512 seed123 (label_only_loss) 应在 93-97% range（与 seed42 一致），验证 phase transition 后 convergence band 的 seed robustness 跨架构成立\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail_512 --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf/ --seed 123 --gradient_checkpointing --label_only_loss --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail512_seed123/ --wandb_project trace-verdict-study --wandb_run_name codellama13b_full_trace_tail512_seed123 && /root/miniconda3/bin/python eval/evaluate.py --condition full_trace_tail_512 --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail512_seed123/final --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf/ --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"466393\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_full_trace_tail512_seed123.log\", \"submitted_at\": \"2026-05-18T20:55:23.272Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 4720, \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail512_seed123/final\", \"wall_clock_seconds\": 8017.9, \"gpu_hours\": 2.23}, \"metrics\": {\"accuracy\": 0.9824, \"accuracy_ci_lower\": 0.9748, \"accuracy_ci_upper\": 0.9899, \"majority_baseline\": 0.7151, \"lift\": 0.2672, \"n\": 1190, \"pass_precision\": 0.9759, \"pass_recall\": 1, \"pass_f1\": 0.9878, \"fail_precision\": 1, \"fail_recall\": 0.9381, \"fail_f1\": 0.968, \"seed_comparison\": {\"seed42_accuracy\": 0.975, \"seed123_accuracy\": 0.9824, \"diff\": 0.0074, \"note\": \"seed123 (98.24%) slightly exceeds seed42 (97.5%); both well above 97% — CodeLlama-13B tail-512 seed-robust\"}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T23:09:01.135Z\"}, \"qwen15b_exception_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:35:27.310Z\", \"updated_at\": \"2026-05-18T23:08:55.815Z\", \"hypothesis\": \"Qwen-1.5B exception_only seed456 应达 ~99.83%（与 seed42 一致），为 W3 reviewer concern 提供 1.5B scale 的方差估计\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 /root/miniconda3/bin/python train/train_sft.py --condition exception_only --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --seed 456 --gradient_checkpointing --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed456/ --wandb_project trace-verdict-study --wandb_run_name qwen15b_exception_only_seed456\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"log_path\": \"~/runs/trace-verdict-study/qwen15b_exception_only_seed456.log\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 456, \"fix_note\": \"Added --gradient_checkpointing to fix OOM\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed456/final\"}, \"metrics\": {\"accuracy\": 0.9983, \"accuracy_ci_lower\": 0.9958, \"accuracy_ci_upper\": 1, \"majority_baseline\": 0.7151, \"lift\": 0.2832, \"n\": 1190, \"pass_precision\": 1, \"pass_recall\": 0.9976, \"pass_f1\": 0.9988, \"fail_precision\": 0.9941, \"fail_recall\": 1, \"fail_f1\": 0.9971, \"seed_comparison\": {\"seed42_accuracy\": 0.9983, \"seed456_accuracy\": 0.9983, \"diff\": 0, \"note\": \"Identical to seed42 to 4 decimal places — exception_only fully seed-robust on Qwen-1.5B\"}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T23:08:55.815Z\"}, \"qwen7b_full_trace_tail512_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:30:02.727Z\", \"updated_at\": \"2026-05-18T20:17:15.561Z\", \"hypothesis\": \"Qwen-7B tail-512 seed456 应在 93-97% range（与 full_trace_tail_512_seed42=93.6% 一致），验证 phase transition 后 convergence band 的 seed robustness\", \"spec\": {\"command\": \"train full_trace_tail_512 qwen7b seed456\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"461573\", \"log_path\": \"/root/runs/trace-verdict-study/qwen7b_full_trace_tail512_seed456.log\", \"submitted_at\": \"2026-05-18T19:15:06.380Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_tail512_seed456/final\", \"wall_clock_seconds\": 3729.2, \"gpu_hours\": 1.04}, \"metrics\": {\"accuracy\": 0.9765, \"majority_baseline\": 0.7151, \"lift\": 0.2613, \"n\": 1190, \"pass_precision\": 0.9746, \"pass_recall\": 0.9929, \"pass_f1\": 0.9837, \"fail_precision\": 0.9814, \"fail_recall\": 0.9351, \"fail_f1\": 0.9577, \"accuracy_ci\": [0.9681, 0.9849]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T20:17:15.562Z\"}, \"deepseek_full_trace_tail512_seed123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:32:10.775Z\", \"updated_at\": \"2026-05-18T20:17:14.170Z\", \"hypothesis\": \"DeepSeek-6.7B tail-512 seed123 应在 93-97% range（与 seed42=93.61% 一致），验证 phase transition 后 convergence band 的 seed robustness。v1 因 GPU OOM 失败，重试。\", \"parent\": \"deepseek_full_trace_tail512_seed123\", \"spec\": {\"command\": \"train full_trace_tail_512 deepseek seed123 v2\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"459485\", \"log_path\": \"/root/runs/trace-verdict-study/deepseek_full_trace_tail512_seed123_v2.log\", \"submitted_at\": \"2026-05-18T18:55:41.122Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 4720, \"model_name\": \"deepseek-coder-6.7b-instruct\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail512_seed123_v2/final\", \"checkpoint_source\": \"deepseek_full_trace_tail512_seed123\", \"eval_data\": \"full_trace_tail_512_eval\", \"wall_clock_seconds\": 4893.0, \"gpu_hours\": 1.36}, \"metrics\": {\"accuracy\": 0.9504, \"majority_baseline\": 0.7151, \"lift\": 0.2353, \"n\": 1190, \"pass_precision\": 0.976, \"pass_recall\": 0.9542, \"pass_f1\": 0.9649, \"fail_precision\": 0.8911, \"fail_recall\": 0.941, \"fail_f1\": 0.9154, \"accuracy_ci\": [0.9387, 0.963]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T20:17:14.170Z\"}, \"qwen7b_full_trace_tail512_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:25:03.679Z\", \"updated_at\": \"2026-05-18T18:39:51.351Z\", \"hypothesis\": \"Qwen-7B tail-512 seed123 应在 93-97% range（与 full_trace_tail_512_seed42=93.6% 一致），验证 phase transition 后 convergence band 的 seed robustness\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail_512 --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --seed 123 --gradient_checkpointing --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_tail512_seed123/ --wandb_project trace-verdict-study --wandb_run_name qwen7b_full_trace_tail512_seed123 && /root/miniconda3/bin/python eval/evaluate.py --condition full_trace_tail_512 --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_tail512_seed123/final --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"452111\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_full_trace_tail512_seed123.log\", \"submitted_at\": \"2026-05-18T16:29:10.415Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_tail512_seed123/final\", \"wall_clock_seconds\": 7840.9, \"gpu_hours\": 2.18}, \"metrics\": {\"accuracy\": 0.9597, \"accuracy_ci_lower\": 0.9487, \"accuracy_ci_upper\": 0.9706, \"majority_baseline\": 0.7151, \"lift\": 0.2445, \"n\": 1190, \"pass_precision\": 0.9751, \"pass_recall\": 0.9683, \"pass_f1\": 0.9717, \"fail_precision\": 0.9217, \"fail_recall\": 0.9381, \"fail_f1\": 0.9298, \"seed_comparison\": {\"seed42_accuracy\": 0.936, \"seed123_accuracy\": 0.9597}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T18:39:51.351Z\"}, \"deepseek_full_trace_tail512_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:25:05.108Z\", \"updated_at\": \"2026-05-18T18:39:50.164Z\", \"hypothesis\": \"DeepSeek-6.7B tail-512 seed456 应在 93-97% range（与 seed42 一致），验证 phase transition 后 convergence band 的 seed robustness\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail_512 --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail512_seed456/ --wandb_project trace-verdict-study --wandb_run_name deepseek_full_trace_tail512_seed456 && /root/miniconda3/bin/python eval/evaluate.py --condition full_trace_tail_512 --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail512_seed456/final --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"452190\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_full_trace_tail512_seed456.log\", \"submitted_at\": \"2026-05-18T16:29:13.700Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail512_seed456/final\", \"wall_clock_seconds\": 7836.5, \"gpu_hours\": 2.18}, \"metrics\": {\"accuracy\": 0.9605, \"accuracy_ci_lower\": 0.9496, \"accuracy_ci_upper\": 0.9714, \"majority_baseline\": 0.7151, \"lift\": 0.2454, \"n\": 1190, \"pass_precision\": 0.9752, \"pass_recall\": 0.9694, \"pass_f1\": 0.9723, \"fail_precision\": 0.9244, \"fail_recall\": 0.9381, \"fail_f1\": 0.9312, \"seed_comparison\": {\"seed42_accuracy\": 0.9361, \"seed456_accuracy\": 0.9605}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T18:39:50.164Z\"}, \"deepseek_full_trace_tail512_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:48:44.674Z\", \"updated_at\": \"2026-05-18T16:31:59.050Z\", \"hypothesis\": \"DeepSeek-6.7B tail-512 seed123 应在 93-97% range（与 seed42 一致），验证 phase transition 后 convergence band 的 seed robustness\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail_512 --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail512_seed123/ --wandb_project trace-verdict-study --wandb_run_name deepseek_full_trace_tail512_seed123 && /root/miniconda3/bin/python eval/evaluate.py --condition full_trace_tail_512 --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail512_seed123/final --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"449827\", \"log_path\": \"/root/runs/trace-verdict-study/deepseek_full_trace_tail512_seed123.log\", \"submitted_at\": \"2026-05-18T15:49:10.240Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"N/A - training OOM at step 0\", \"wall_clock_seconds\": 2537.4, \"gpu_hours\": 0.7}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T16:31:27.635Z\", \"metrics\": {\"error\": \"CUDA OOM at step 0/444\", \"exit_code\": 1, \"failure_time\": \"2026-05-18T15:49:48Z\", \"cause\": \"GPU 0 memory exhausted (43.45 GiB PyTorch allocated, only 167.56 MiB free when trying to allocate 178 MiB)\", \"seed_comparison\": {\"seed42_accuracy\": 0.9361, \"seed123_accuracy\": \"N/A - OOM crash\"}}}, \"qwen15b_full_trace_tail512_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:48:43.426Z\", \"updated_at\": \"2026-05-18T16:28:37.149Z\", \"hypothesis\": \"Qwen-1.5B tail-512 seed456 应在 93-97% range（与 seed42 一致），验证 phase transition 后 convergence band 的 seed robustness\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail_512 --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail512_seed456/ --wandb_project trace-verdict-study --wandb_run_name qwen15b_full_trace_tail512_seed456 && /root/miniconda3/bin/python eval/evaluate.py --condition full_trace_tail_512 --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail512_seed456/final --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"449685\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail512_seed456/\", \"submitted_at\": \"2026-05-18T15:49:06.692Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail512_seed456/final\", \"wall_clock_seconds\": 2370.5, \"gpu_hours\": 0.66}, \"metrics\": {\"accuracy\": 0.9672, \"accuracy_ci_lower\": 0.9563, \"accuracy_ci_upper\": 0.9773, \"majority_baseline\": 0.7151, \"lift\": 0.2521, \"n\": 1190, \"pass_precision\": 0.9765, \"pass_recall\": 0.9777, \"pass_f1\": 0.9771, \"fail_precision\": 0.9438, \"fail_recall\": 0.941, \"fail_f1\": 0.9424, \"seed_comparison\": {\"seed42_accuracy\": 0.956, \"seed123_accuracy\": 0.9765, \"seed456_accuracy\": 0.9672, \"note\": \"seed456 (96.72%) within convergence band [95.6%, 97.65%], confirming seed robustness post-phase-transition\"}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T16:28:37.149Z\"}, \"codellama13b_full_trace_tail384_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:06:06.157Z\", \"updated_at\": \"2026-05-18T15:51:11.441Z\", \"hypothesis\": \"CodeLlama-13B tail-384 (label_only_loss) 应在 85-95% 之间（256→512 phase transition 中间点），验证 label_only_loss 在短序列下也有效\", \"spec\": {\"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\", \"label_only_loss\": true}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail384_seed42/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail384_seed42/runs\", \"metrics\": {\"accuracy\": 0.8269, \"accuracy_ci_lower\": 0.8067, \"accuracy_ci_upper\": 0.8471, \"majority_baseline\": 0.7151, \"lift\": 0.1118, \"n\": 1190, \"pass_precision\": 0.8314, \"pass_recall\": 0.9506, \"pass_f1\": 0.8871, \"fail_precision\": 0.8065, \"fail_recall\": 0.5162, \"fail_f1\": 0.6295}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T15:51:11.441Z\"}, \"qwen15b_full_trace_tail512_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:56:42.559Z\", \"updated_at\": \"2026-05-18T15:51:10.277Z\", \"hypothesis\": \"Qwen-1.5B tail-512 seed123 应在 93-97% range（与 seed42 一致），验证 phase transition 后 convergence band 的 seed robustness\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail_512 --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail512_seed123/ --wandb_project trace-verdict-study --wandb_run_name qwen15b_full_trace_tail512_seed123 && /root/miniconda3/bin/python eval/evaluate.py --condition full_trace_tail_512 --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail512_seed123/final --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"447690\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_full_trace_tail512_seed123.log\", \"submitted_at\": \"2026-05-18T15:16:16.177Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 2094.1, \"gpu_hours\": 0.58}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail512_seed123/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail512_seed123/runs\", \"metrics\": {\"accuracy\": 0.9765, \"accuracy_ci_lower\": 0.9681, \"accuracy_ci_upper\": 0.9849, \"majority_baseline\": 0.7151, \"lift\": 0.2613, \"n\": 1190, \"pass_precision\": 0.9757, \"pass_recall\": 0.9918, \"pass_f1\": 0.9837, \"fail_precision\": 0.9785, \"fail_recall\": 0.9381, \"fail_f1\": 0.9578, \"seed_comparison\": {\"seed42_accuracy\": 0.956, \"seed123_accuracy\": 0.9765, \"note\": \"seed123 (97.65%) exceeds seed42 (95.6%) by 2pp; both in convergence band post-phase-transition\"}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T15:51:10.277Z\"}, \"qwen15b_full_trace_tail384_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:06:04.119Z\", \"updated_at\": \"2026-05-18T15:17:01.787Z\", \"hypothesis\": \"Qwen-1.5B tail-384 应在 80-90% 之间（小模型在 transition zone 可能更低），精确定位 phase transition 曲线形状\", \"spec\": {\"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\", \"label_only_loss\": false, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail384_seed42/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail384_seed42\"}, \"metrics\": {\"accuracy\": 0.7361, \"majority_baseline\": 0.7151, \"lift\": 0.021, \"n\": 1190, \"pass_precision\": 0.8069, \"pass_recall\": 0.8296, \"pass_f1\": 0.8181, \"fail_precision\": 0.5397, \"fail_recall\": 0.5015, \"fail_f1\": 0.5199, \"accuracy_ci\": [0.7101, 0.7622]}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T15:17:01.788Z\"}, \"qwen7b_full_trace_tail384_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:06:01.294Z\", \"updated_at\": \"2026-05-18T13:52:36.911Z\", \"hypothesis\": \"Qwen-7B tail-384 应在 85-93% 之间（256→512 phase transition 的中间点），精确定位 phase transition 曲线形状\", \"spec\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"command\": \"source /root/miniconda3/bin/activate && python train/train_sft.py --condition full_trace_tail_384 --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_tail384_seed42 --gpu 1 --seed 42 --gradient_checkpointing\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_tail384_seed42/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_tail384_seed42/final/eval_results.json\"}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.798, \"accuracy_ci_lower\": 0.776, \"accuracy_ci_upper\": 0.821, \"majority_baseline\": 0.715, \"lift\": 0.083, \"n\": 1190, \"pass_precision\": 0.89, \"pass_recall\": 0.82, \"pass_f1\": 0.85, \"fail_precision\": 0.62, \"fail_recall\": 0.75, \"fail_f1\": 0.68}, \"completed_at\": \"2026-05-18T13:52:36.911Z\"}, \"deepseek_full_trace_tail384_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:06:02.727Z\", \"updated_at\": \"2026-05-18T13:52:35.606Z\", \"hypothesis\": \"DeepSeek-6.7B tail-384 应在 85-93% 之间（256→512 phase transition 的中间点），精确定位 phase transition 曲线形状\", \"spec\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"command\": \"source /root/miniconda3/bin/activate && python train/train_sft.py --condition full_trace_tail_384 --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail384_seed42 --gpu 0 --seed 42\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"deepseek-coder-6.7b-instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail384_seed42/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail384_seed42/final/eval_results.json\"}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.807, \"accuracy_ci_lower\": 0.786, \"accuracy_ci_upper\": 0.829, \"majority_baseline\": 0.715, \"lift\": 0.092, \"n\": 1190, \"pass_precision\": 0.83, \"pass_recall\": 0.92, \"pass_f1\": 0.87, \"fail_precision\": 0.73, \"fail_recall\": 0.51, \"fail_f1\": 0.6}, \"completed_at\": \"2026-05-18T13:52:35.607Z\"}, \"qwen7b_full_trace_head2048_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T08:01:11.546Z\", \"updated_at\": \"2026-05-18T12:07:15.686Z\", \"hypothesis\": \"Qwen-7B head-2048 应在 75-82% (signal-poor convergence band)，与其他 3 模型 head-2048 (75.3-79.9%) 对齐，补全 4 模型 head-tail gap claim\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen7b_full_trace_head2048_seed42/\", \"log_path\": \"~/runs/trace-verdict-study/qwen7b_full_trace_head2048_seed42.log\"}, \"conclusion\": \"success\", \"metrics\": {\"accuracy_epoch1\": 0.816, \"accuracy_epoch3\": 0.81, \"pass_f1_epoch1\": 0.87, \"fail_f1_epoch1\": 0.686, \"pass_f1_epoch3\": 0.866, \"fail_f1_epoch3\": 0.674, \"best_accuracy\": 0.816, \"best_epoch\": 1}, \"completed_at\": \"2026-05-18T12:07:15.686Z\"}, \"codellama13b_full_trace_tail2048_seed42_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T07:51:07.325Z\", \"updated_at\": \"2026-05-18T12:07:14.546Z\", \"hypothesis\": \"CodeLlama-13B tail-2048 用 label_only_loss 应恢复到 95-98%（与其他 3 模型 tail-2048 对齐），确认 v2 的 29.6% 源于 full-sequence loss 稀释\", \"parent\": \"codellama13b_full_trace_tail2048_seed42_v2\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail2048_seed42_v3/\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_full_trace_tail2048_seed42_v3.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"accuracy_epoch1\": 0.071, \"accuracy_epoch3\": 0.418, \"pass_f1_epoch3\": 0.416, \"fail_f1_epoch3\": 0.421, \"pass_f1_epoch1\": 0.035, \"fail_f1_epoch1\": 0.342, \"train_loss\": 0.785}, \"completed_at\": \"2026-05-18T12:07:14.546Z\"}, \"codellama13b_full_trace_tail1024_seed42_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:39:08.941Z\", \"updated_at\": \"2026-05-18T09:43:42.053Z\", \"hypothesis\": \"CodeLlama-13B tail-1024 用 label_only_loss 应恢复到 ~96.5%（与 DeepSeek 96.47%、Qwen-1.5B 96.6% 对齐），确认 v2 的 87.6% 源于 full-sequence loss 稀释而非 tail-1024 条件本身\", \"parent\": \"codellama13b_full_trace_tail1024_seed42_v2\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail1024_seed42_v3/\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_full_trace_tail1024_seed42_v3.log\"}, \"conclusion\": \"success\", \"metrics\": {\"accuracy_epoch1\": 0.9824, \"accuracy_epoch3\": 0.9756, \"pass_f1_epoch1\": 0.988, \"fail_f1_epoch1\": 0.968, \"pass_f1_epoch3\": 0.983, \"fail_f1_epoch3\": 0.955, \"best_accuracy\": 0.9824, \"best_epoch\": 1, \"overfitting\": true}, \"completed_at\": \"2026-05-18T09:43:42.053Z\"}, \"codellama13b_full_trace_tail2048_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T03:52:51.335Z\", \"updated_at\": \"2026-05-18T07:51:13.642Z\", \"hypothesis\": \"CodeLlama-13B tail-2048 应在 95-98%，head-tail gap ≥15pp，确认 signal positional concentration 跨 4 模型\", \"parent\": \"codellama13b_full_trace_head2048_seed42\", \"spec\": {\"command\": \"bash -c 'cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail2048_seed42_v2 --seed 42 --wandb_project trace-verdict-study --wandb_run_name codellama13b_full_trace_tail2048_seed42_v2 --gradient_checkpointing'\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"pid\": \"405136\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_full_trace_tail2048_seed42_v2.log\", \"submitted_at\": \"2026-05-18T03:53:12.769Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail2048_seed42_v2/final\", \"wall_clock_seconds\": 14280.9, \"gpu_hours\": 3.97}, \"metrics\": {\"accuracy_epoch1\": 0.2849, \"accuracy_epoch3\": 0.2958, \"pass_recall_epoch3\": 0.016, \"fail_recall_epoch3\": 0.997, \"majority_baseline\": 0.715, \"n_test\": 1190, \"note\": \"Catastrophic failure: model predicts fail for almost everything. Full-sequence loss dilution with CodeLlama tokenizer at 2048 tokens.\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T07:51:13.642Z\"}, \"codellama13b_full_trace_tail1024_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T03:25:33.875Z\", \"updated_at\": \"2026-05-18T06:15:35.443Z\", \"hypothesis\": \"CodeLlama-13B tail-1024 应收敛到 96.5% 附近（与 DeepSeek 96.47%、Qwen-1.5B 96.6% 不可区分），确认 tail-1024 convergence band 跨 4 模型 universal\", \"parent\": \"codellama13b_full_trace_tail512_seed42\", \"spec\": {\"command\": \"bash -c 'cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail_1024 --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail1024_seed42_v2 --seed 42 --wandb_project trace-verdict-study --wandb_run_name codellama13b_full_trace_tail1024_seed42_v2 --gradient_checkpointing'\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"pid\": \"403386\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_full_trace_tail1024_seed42_v2.log\", \"submitted_at\": \"2026-05-18T03:26:05.733Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail1024_seed42_v2/final\", \"wall_clock_seconds\": 10169.7, \"gpu_hours\": 2.82}, \"metrics\": {\"accuracy\": 0.876, \"accuracy_ci_lower\": 0.856, \"accuracy_ci_upper\": 0.893, \"majority_baseline\": 0.715, \"lift_pp\": 16.1, \"pass_precision\": 0.85, \"pass_recall\": 1, \"pass_f1\": 0.92, \"fail_precision\": 1, \"fail_recall\": 0.56, \"fail_f1\": 0.72, \"n_test\": 1190, \"train_loss\": 0.0937, \"eval_loss\": 0.1859}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T06:15:35.443Z\"}, \"codellama13b_full_trace_tail2048_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T03:47:21.197Z\", \"updated_at\": \"2026-05-18T03:52:43.842Z\", \"hypothesis\": \"CodeLlama-13B tail-2048 应在 95-98%，head-tail gap ≥15pp，确认 signal positional concentration 跨 4 模型\", \"parent\": \"codellama13b_full_trace_head2048_seed42\", \"spec\": {\"command\": \"bash -c 'cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail_2048 --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail2048_seed42 --seed 42 --wandb_project trace-verdict-study --wandb_run_name codellama13b_full_trace_tail2048_seed42 --gradient_checkpointing'\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"pid\": \"404579\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-18T03:47:52.601Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\", \"checkpoint_path\": \"N/A\", \"failure_reason\": \"Invalid condition: full_trace_tail_2048 not in choices. Correct condition is full_trace_tail.\", \"wall_clock_seconds\": 291.2, \"gpu_hours\": 0.08}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T03:52:43.842Z\"}, \"codellama13b_full_trace_head2048_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T23:20:24.115Z\", \"updated_at\": \"2026-05-18T03:37:20.611Z\", \"hypothesis\": \"CodeLlama-13B head-2048 truncation should yield 75-82% accuracy, confirming signal positional concentration pattern across 4 model families where tail-2048 significantly outperforms head-2048\", \"parent\": \"codellama13b_exception_only_seed42\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python train.py --model /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf/ --condition full_trace --truncation head --max_tokens 2048 --seed 42'\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"pid\": \"391743\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_full_trace_head2048_seed42.log\", \"submitted_at\": \"2026-05-17T23:42:34.564Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\", \"wall_clock_seconds\": 14086.0, \"gpu_hours\": 3.91}, \"reproduce\": {\"finished_at\": \"2026-05-18T03:32:04.847Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T03:32:08.458585+00:00\"}]}, \"metrics\": {\"accuracy\": 0.7992, \"majority_baseline\": 0.7151, \"lift\": 0.084, \"n_test\": 1190, \"pass_precision\": 0.8566, \"pass_recall\": 0.8637, \"pass_f1\": 0.8602, \"fail_precision\": 0.6506, \"fail_recall\": 0.6372, \"fail_f1\": 0.6438, \"train_loss\": 0.0452, \"eval_loss\": 0.111, \"accuracy_ci_lower\": 0.7765, \"accuracy_ci_upper\": 0.8227}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_head2048_seed42/final\", \"log_path\": \"/root/trace-verdict-study/logs/codellama13b_head2048_seed42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T03:37:20.611Z\"}, \"codellama13b_full_trace_tail256_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T01:37:42.953Z\", \"updated_at\": \"2026-05-18T03:33:11.185Z\", \"hypothesis\": \"CodeLlama-13B tail-256 应在 78-85%，与 7B 级模型 tail-256 (76-79%) 类似或略高，确认 256 tokens 信号不足是 universal 的\", \"parent\": \"codellama13b_full_trace_tail512_seed42\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python train.py --model /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf/ --condition full_trace --truncation tail --max_tokens 256 --seed 42'\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"pid\": \"397742\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_full_trace_tail256_seed42.log\", \"submitted_at\": \"2026-05-18T01:41:17.373Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\", \"wall_clock_seconds\": 6713.8, \"gpu_hours\": 1.86}, \"reproduce\": {\"finished_at\": \"2026-05-18T02:23:11.443Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T02:23:17.445961+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.779, \"accuracy_ci_lower\": 0.757, \"accuracy_ci_upper\": 0.803, \"pass_f1\": 0.843, \"fail_f1\": 0.626, \"pass_precision\": 0.856, \"pass_recall\": 0.831, \"fail_precision\": 0.604, \"fail_recall\": 0.649, \"majority_baseline\": 0.715, \"lift\": 0.064, \"train_loss\": 0.245, \"eval_loss\": 0.615}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_full_trace_tail256_seed42/final\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_full_trace_tail256_seed42.log\", \"completed_at\": \"2026-05-18T03:33:11.186Z\"}, \"codellama13b_full_trace_tail1024_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T01:37:33.166Z\", \"updated_at\": \"2026-05-18T03:25:19.162Z\", \"hypothesis\": \"CodeLlama-13B tail-1024 应收敛到 96.5% 附近（与 DeepSeek 96.47%、Qwen-1.5B 96.6% 不可区分），确认 tail-1024 convergence band 跨 4 模型 universal\", \"parent\": \"codellama13b_full_trace_tail512_seed42\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && python train.py --model /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf/ --condition full_trace --truncation tail --max_tokens 1024 --seed 42'\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"pid\": \"unknown\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-18T02:28:32.411Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\", \"checkpoint_path\": \"N/A\", \"failure_reason\": \"Wrong script path: used train.py instead of train/train_sft.py. Process exited immediately with Errno 2.\", \"wall_clock_seconds\": 3406.8, \"gpu_hours\": 0.95}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T03:25:19.162Z\"}, \"qwen15b_full_trace_tail1024_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T22:48:55.914Z\", \"updated_at\": \"2026-05-18T01:45:09.341Z\", \"hypothesis\": \"1.5B tail-1024 可能低于 tail-512 (95.6%)，如同 7B non-monotonicity；因中等长度 trace 包含 noisy intermediate states\", \"parent\": \"qwen15b_full_trace_tail512_seed42\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python train.py --model /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --condition full_trace --truncation tail --max_tokens 1024 --seed 42'\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"pid\": \"388161\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_full_trace_tail1024_seed42.log\", \"submitted_at\": \"2026-05-17T22:51:42.254Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\", \"wall_clock_seconds\": 10407.1, \"gpu_hours\": 2.89}, \"reproduce\": {\"finished_at\": \"2026-05-17T23:12:12.100Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T23:12:15.209322+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail1024_seed42/final\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_full_trace_tail1024_seed42.log\", \"metrics\": {\"accuracy\": 0.966, \"accuracy_ci_low\": 0.955, \"accuracy_ci_high\": 0.976, \"pass_precision\": 0.96, \"pass_recall\": 0.99, \"pass_f1\": 0.98, \"fail_precision\": 0.97, \"fail_recall\": 0.91, \"fail_f1\": 0.94, \"eval_loss\": 0.1983, \"train_loss\": 0.1187, \"majority_baseline\": 0.715, \"lift_over_majority_pp\": 25}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T01:45:09.341Z\"}, \"deepseek_full_trace_tail1024_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T21:23:57.882Z\", \"updated_at\": \"2026-05-17T23:14:09.157Z\", \"hypothesis\": \"DeepSeek tail-1024 可能低于 tail-512（如同 Qwen-7B non-monotonicity），因为 1024 tokens 包含了 noisy intermediate states；如果也出现 non-monotonicity 则确认跨架构\", \"parent\": \"deepseek_full_trace_tail256_seed42\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail1024_seed42/final\", \"log_path\": \"/root/trace-verdict-study/logs/deepseek_tail1024_seed42.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T23:09:36.935Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T23:09:39.909092+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9647, \"accuracy_ci_lower\": 0.9538, \"accuracy_ci_upper\": 0.9748, \"pass_precision\": 0.964, \"pass_recall\": 0.987, \"pass_f1\": 0.976, \"fail_precision\": 0.966, \"fail_recall\": 0.909, \"fail_f1\": 0.936, \"majority_baseline\": 0.7151, \"n_test\": 1190}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T23:14:09.157Z\"}, \"deepseek_full_trace_tail512_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T21:12:42.017Z\", \"updated_at\": \"2026-05-17T22:32:35.246Z\", \"hypothesis\": \"DeepSeek tail-512 应在 88-94%，与 Qwen-7B tail-512 (93.61%) 对齐则 phase transition 阈值 architecture-independent\", \"parent\": \"deepseek_full_trace_tail256_seed42\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python train.py --model /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --condition full_trace --truncation tail --max_tokens 512 --seed 42'\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"pid\": \"382268\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_full_trace_tail512_seed42.log\", \"submitted_at\": \"2026-05-17T21:14:49.694Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"deepseek-coder-6.7b-instruct\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\", \"wall_clock_seconds\": 4665.6, \"gpu_hours\": 1.3}, \"reproduce\": {\"finished_at\": \"2026-05-17T22:29:55.961Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T22:29:58.909048+00:00\"}]}, \"metrics\": {\"accuracy\": 0.939, \"accuracy_ci_lower\": 0.926, \"accuracy_ci_upper\": 0.953, \"majority_baseline\": 0.715, \"lift_over_majority\": 0.224, \"pass_precision\": 0.97, \"pass_recall\": 0.94, \"pass_f1\": 0.96, \"fail_precision\": 0.86, \"fail_recall\": 0.94, \"fail_f1\": 0.9, \"n_test\": 1190}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail512_seed42/final\", \"log_path\": \"/root/trace-verdict-study/logs/deepseek_tail512_seed42.log\", \"completed_at\": \"2026-05-17T22:32:35.246Z\"}, \"qwen15b_full_trace_tail512_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T20:58:30.671Z\", \"updated_at\": \"2026-05-17T21:20:53.258Z\", \"hypothesis\": \"Qwen-1.5B with tail-512 truncation should achieve 88-94% accuracy, comparable to Qwen-7B tail-512 (93.61%), indicating the phase transition threshold between 256-512 tokens is scale-invariant across model sizes\", \"parent\": \"qwen15b_full_trace_tail256_seed42\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail512_seed42/final\", \"log_path\": \"/root/trace-verdict-study/logs/qwen15b_tail512_seed42.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T21:18:34.835Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T21:18:38.541236+00:00\"}]}, \"metrics\": {\"accuracy\": 0.956, \"accuracy_ci_lower\": 0.945, \"accuracy_ci_upper\": 0.968, \"majority_baseline\": 0.715, \"lift_over_majority\": 0.241, \"eval_loss\": 0.263, \"train_loss\": 0.154, \"pass_precision\": 0.98, \"pass_recall\": 0.96, \"pass_f1\": 0.97, \"fail_precision\": 0.91, \"fail_recall\": 0.94, \"fail_f1\": 0.92, \"eval_mean_token_accuracy\": 0.949}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T21:20:53.258Z\"}, \"deepseek_full_trace_tail256_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T20:34:26.838Z\", \"updated_at\": \"2026-05-17T21:10:51.276Z\", \"hypothesis\": \"DeepSeek tail-256 应在 75-82% 范围（与 Qwen-7B tail-256=78.9% 类似），确认 256-512 phase transition 是 architecture-independent\", \"parent\": \"full_trace_tail256_seed42\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python train.py --model /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --condition full_trace --truncation tail --max_tokens 256 --seed 42'\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"pid\": \"379548\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_full_trace_tail256_seed42.log\", \"submitted_at\": \"2026-05-17T20:38:11.778Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"deepseek-coder-6.7b-instruct\", \"seed\": 42, \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\", \"wall_clock_seconds\": 1959.5, \"gpu_hours\": 0.54}, \"reproduce\": {\"finished_at\": \"2026-05-17T21:07:49.509Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T21:07:52.391149+00:00\"}]}, \"metrics\": {\"accuracy\": 0.7639, \"accuracy_ci_lower\": 0.7403, \"accuracy_ci_upper\": 0.7874, \"pass_precision\": 0.8058, \"pass_recall\": 0.8825, \"pass_f1\": 0.8424, \"fail_precision\": 0.6124, \"fail_recall\": 0.4661, \"fail_f1\": 0.5293, \"majority_baseline\": 0.7151, \"lift\": 0.0487, \"eval_loss\": 0.5117, \"train_loss\": 0.2367}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail256_seed42/final\", \"log_path\": \"/root/trace-verdict-study/logs/deepseek_tail256_seed42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T21:10:51.276Z\"}, \"qwen15b_full_trace_tail256_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T20:27:09.863Z\", \"updated_at\": \"2026-05-17T20:55:21.799Z\", \"hypothesis\": \"Cross-scale tail-256: Qwen-1.5B tail-256 should show similar accuracy to 7B tail-256 (78.9%), confirming the 256-512 phase transition is signal-limited not capacity-limited\", \"parent\": \"full_trace_tail256_seed42\", \"spec\": {\"command\": \"python train.py --model Qwen2.5-Coder-1.5B-Instruct --condition full_trace --truncation tail --max_tokens 256 --seed 42\", \"server\": \"westd-11235\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:1\", \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T20:42:23.364Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T20:42:24.637Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T20:42:27.231757+00:00\"}]}, \"metrics\": {\"accuracy\": 0.726, \"accuracy_ci_lower\": 0.7, \"accuracy_ci_upper\": 0.753, \"majority_baseline\": 0.715, \"lift_over_majority\": 0.011, \"lift_ci_lower\": -0.021, \"lift_ci_upper\": 0.044, \"pass_precision\": 0.82, \"pass_recall\": 0.79, \"pass_f1\": 0.8, \"fail_precision\": 0.52, \"fail_recall\": 0.57, \"fail_f1\": 0.54, \"eval_loss\": 0.5936, \"train_loss\": 0.2687}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail256_seed42/final\", \"log_path\": \"/root/trace-verdict-study/logs/qwen15b_tail256_seed42.log\"}, \"deepseek_full_trace_head2048_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T17:56:22.154Z\", \"updated_at\": \"2026-05-17T20:31:41.861Z\", \"hypothesis\": \"Cross-architecture head-truncation: DeepSeek head-2048 should achieve 80-85% (similar to Qwen-7B 81.76%), and tail-2048 (94.96%) vs head-2048 gap should be >=10pp, confirming signal positional concentration is architecture-independent\", \"parent\": \"deepseek_full_trace_tail2048_seed42\", \"spec\": {\"command\": \"python train.py --model deepseek-coder-6.7b-instruct --condition full_trace --truncation head --max_tokens 2048 --seed 42\", \"server\": \"westd-11235\", \"data_path\": \"/root/trace-verdict-study/data/\", \"data_count\": 600, \"model_name\": \"deepseek-coder-6.7b-instruct\", \"seed\": 42, \"gpu\": \"cuda:0\", \"checkpoint_source\": \"trained_from_scratch\", \"eval_data\": \"/root/trace-verdict-study/data/test.jsonl\"}, \"metrics\": {\"accuracy\": 0.787, \"accuracy_ci_lower\": 0.765, \"accuracy_ci_upper\": 0.81, \"majority_baseline\": 0.715, \"lift_pp\": 7.2, \"pass_precision\": 0.84, \"pass_recall\": 0.86, \"pass_f1\": 0.85, \"fail_precision\": 0.63, \"fail_recall\": 0.6, \"fail_f1\": 0.62}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_head2048_seed42/\", \"log_path\": \"/root/trace-verdict-study/logs/deepseek_head2048_seed42.log\", \"completed_at\": \"2026-05-17T20:31:41.861Z\"}, \"full_trace_tail256_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T19:29:18.715Z\", \"updated_at\": \"2026-05-17T20:26:35.350Z\", \"hypothesis\": \"Tail-256 truncation (keeping last 256 tokens of execution trace) still provides sufficient signal for verdict prediction, extending the budget curve below tail-512 (93.61%) to validate the accuracy-budget tradeoff at minimal trace length.\", \"parent\": \"full_trace_tail_512_seed42\", \"spec\": {\"command\": \"python train/train_sft.py --condition full_trace_tail_256 --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_tail256_seed42 && python eval/evaluate.py --condition full_trace_tail_256 --checkpoint_dir .../final --gpu 0 --save_predictions\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_tail_256_{train,test}.jsonl\", \"data_count\": 5910, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_tail256_seed42/\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_tail256_seed42.log\", \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_tail_256_test.jsonl\"}, \"metrics\": {\"accuracy\": 0.789, \"accuracy_ci_lower\": 0.765, \"accuracy_ci_upper\": 0.813, \"pass_f1\": 0.845, \"fail_f1\": 0.671, \"n_test\": 1190}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T20:26:35.350Z\"}, \"qwen15b_full_trace_head2048_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T17:56:23.519Z\", \"updated_at\": \"2026-05-17T19:27:55.067Z\", \"hypothesis\": \"Cross-scale head-truncation: Qwen-1.5B head-2048 should achieve 75-82%, and tail-2048 (97.90%) vs head-2048 gap should be >=15pp, confirming signal positional concentration holds at small scale\", \"parent\": \"qwen15b_full_trace_tail2048_seed42\", \"metrics\": {\"accuracy\": 0.7529, \"accuracy_ci_lower\": 0.7286, \"accuracy_ci_upper\": 0.7782, \"pass_precision\": 0.799, \"pass_recall\": 0.874, \"pass_f1\": 0.835, \"fail_precision\": 0.587, \"fail_recall\": 0.448, \"fail_f1\": 0.508, \"n_test\": 1190}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_head2048_seed42/final/\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_head2048_seed42/final/eval_results.json\", \"spec\": {\"command\": \"python train/train_sft.py --condition full_trace_head --model_path Qwen2.5-Coder-1.5B-Instruct + eval\", \"server\": \"westd-11235\", \"data_path\": \"/root/trace-verdict-study/data/full_trace_head_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"self-trained SFT on full_trace_head data\", \"eval_data\": \"/root/trace-verdict-study/data/full_trace_head_test.jsonl\"}, \"completed_at\": \"2026-05-17T19:27:55.067Z\"}, \"deepseek_full_trace_tail2048_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T14:52:23.728Z\", \"updated_at\": \"2026-05-17T17:18:48.327Z\", \"hypothesis\": \"Tail-truncation signal concentration hypothesis generalizes across architectures: DeepSeek-Coder-6.7B with tail-2048 truncation should achieve accuracy comparable to Qwen-7B tail-2048 (97.31%), because execution trace endings contain the most verdict-relevant signals regardless of model architecture.\", \"parent\": \"full_trace_tail_seed42\", \"spec\": {\"command\": \"/root/miniconda3/bin/python train/train_sft.py --condition full_trace_tail --model_path ... --gradient_checkpointing --gpu 0 --seed 42 --output_dir ... && /root/miniconda3/bin/python eval/evaluate.py --condition full_trace_tail --checkpoint_dir .../final --gpu 0 --save_predictions\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_tail_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"DeepSeek-Coder-6.7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail2048_seed42/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail2048_seed42/train_eval.log\", \"checkpoint_source\": \"self-trained SFT on full_trace_tail data\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_tail_test.jsonl (1190 samples)\"}, \"metrics\": {\"accuracy\": 0.9496, \"accuracy_ci_lower\": 0.937, \"accuracy_ci_upper\": 0.9622, \"pass_precision\": 0.9692, \"pass_recall\": 0.96, \"pass_f1\": 0.9646, \"fail_precision\": 0.902, \"fail_recall\": 0.9233, \"fail_f1\": 0.9125, \"n_test\": 1190}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_tail2048_seed42/final/\", \"completed_at\": \"2026-05-17T17:18:48.327Z\"}, \"qwen15b_full_trace_tail2048_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T14:52:25.576Z\", \"updated_at\": \"2026-05-17T17:18:47.435Z\", \"hypothesis\": \"Tail-truncation concentrates diagnostic signal (final execution states, exceptions) at training time. If this hypothesis holds, Qwen2.5-Coder-1.5B with tail-2048 truncation should achieve accuracy comparable to 7B tail-2048 (97.31%), significantly outperforming head-truncation baselines on the same model size.\", \"parent\": \"full_trace_tail_seed42\", \"spec\": {\"command\": \"python train/train_sft.py --condition full_trace_tail --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail2048_seed42 --gradient_checkpointing --wandb_project trace-verdict-study --wandb_run_name qwen15b_full_trace_tail2048_seed42 && python eval/evaluate.py --condition full_trace_tail --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail2048_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail2048_seed42/final/eval_results.json --save_predictions\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_tail_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:1\", \"checkpoint_source\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail2048_seed42/final\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_tail_test.jsonl\"}, \"metrics\": {\"accuracy\": 0.979, \"accuracy_ci_lower\": 0.9706, \"accuracy_ci_upper\": 0.9874, \"pass_precision\": 0.9758, \"pass_recall\": 0.9953, \"pass_f1\": 0.9855, \"fail_precision\": 0.9876, \"fail_recall\": 0.9381, \"fail_f1\": 0.9622, \"n_test\": 1190}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail2048_seed42/final/\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_tail2048_seed42.log\", \"completed_at\": \"2026-05-17T17:18:47.435Z\"}, \"fewshot_qwen7b_exception_only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T14:05:16.779Z\", \"updated_at\": \"2026-05-17T14:16:13.380Z\", \"hypothesis\": \"Few-shot (3 examples) improves over zero-shot (89.08%) but remains far below SFT (99.83%) because 3 in-context examples cannot cover all caught exception patterns, establishing the zero-shot → few-shot → SFT progression\", \"parent\": \"zeroshot_qwen7b_exception_only\", \"metrics\": {\"accuracy\": 0.9084, \"accuracy_ci_lower\": 0.8908, \"accuracy_ci_upper\": 0.9244, \"pass_precision\": 0.9245, \"pass_recall\": 0.9495, \"pass_f1\": 0.9368, \"fail_precision\": 0.8639, \"fail_recall\": 0.8053, \"fail_f1\": 0.8336, \"n_test\": 1190, \"n_unknown\": 0}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/fewshot_qwen7b_exception_only/\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/fewshot_qwen7b_exception_only/eval_results.json\", \"spec\": {\"command\": \"python eval/fewshot_eval.py --model_path Qwen2.5-Coder-7B-Instruct --n_examples 3 --batch_size 2\", \"server\": \"westd-11235\", \"data_path\": \"/root/trace-verdict-study/data/exception_only_test.jsonl\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 0, \"checkpoint_source\": \"pretrained (no fine-tuning)\", \"eval_data\": \"/root/trace-verdict-study/data/exception_only_test.jsonl\"}, \"completed_at\": \"2026-05-17T14:16:13.380Z\"}, \"zeroshot_qwen15b_exception_only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T14:05:17.683Z\", \"updated_at\": \"2026-05-17T14:13:44.604Z\", \"hypothesis\": \"Zero-shot cross-scale baseline: Qwen-1.5B zero-shot may perform poorly (similar to CodeLlama-13B) due to limited capacity, but SFT normalizes it to 99.83%, demonstrating SFT eliminates scale variance\", \"parent\": \"zeroshot_qwen7b_exception_only\", \"metrics\": {\"accuracy\": 0.9345, \"accuracy_ci_lower\": 0.9202, \"accuracy_ci_upper\": 0.9479, \"pass_f1\": 0.969, \"fail_f1\": 0.873, \"pass_recall\": 0.9906, \"fail_recall\": 0.7935, \"n_test\": 1190, \"n_unknown\": 24}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/zeroshot_qwen15b_exception_only/\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/zeroshot_qwen15b_exception_only/eval_results.json\", \"spec\": {\"command\": \"python eval/zeroshot_eval.py --model_path Qwen2.5-Coder-1.5B-Instruct --data_path exception_only_test.jsonl --gpu 0\", \"server\": \"westd-11235\", \"data_path\": \"/root/trace-verdict-study/data/exception_only_test.jsonl\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 0, \"checkpoint_source\": \"pretrained (no fine-tuning)\", \"eval_data\": \"/root/trace-verdict-study/data/exception_only_test.jsonl\"}, \"completed_at\": \"2026-05-17T14:13:44.604Z\"}, \"zeroshot_codellama13b_exception_only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:49:28.046Z\", \"updated_at\": \"2026-05-17T14:03:43.831Z\", \"hypothesis\": \"Zero-shot cross-scale baseline: untuned CodeLlama-13B-Instruct (largest model tested) still cannot match SFT accuracy on exception_only verdict prediction, confirming SFT necessity holds even with 2x more parameters\", \"parent\": \"zeroshot_qwen7b_exception_only\", \"metrics\": {\"accuracy\": 0.5101, \"accuracy_ci_lower\": 0.4824, \"accuracy_ci_upper\": 0.5395, \"pass_precision\": 1, \"pass_recall\": 0.3502, \"pass_f1\": 0.5187, \"fail_precision\": 0.3585, \"fail_recall\": 0.9115, \"fail_f1\": 0.5146, \"n_test\": 1190, \"n_unknown\": 30}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/zeroshot_codellama13b_exception_only/\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/zeroshot_codellama13b_exception_only/eval_results.json\", \"spec\": {\"command\": \"python eval/zeroshot_eval.py --model_path CodeLlama-13b-Instruct-hf --data_path exception_only_test.jsonl --gpu 0\", \"server\": \"westd-11235\", \"data_path\": \"/root/trace-verdict-study/data/exception_only_test.jsonl\", \"data_count\": 1190, \"model_name\": \"CodeLlama-13B-Instruct\", \"seed\": 0, \"checkpoint_source\": \"pretrained (no fine-tuning)\", \"eval_data\": \"/root/trace-verdict-study/data/exception_only_test.jsonl\"}, \"completed_at\": \"2026-05-17T14:03:43.831Z\"}, \"zeroshot_deepseek7b_exception_only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:00:43.420Z\", \"updated_at\": \"2026-05-17T13:47:37.166Z\", \"hypothesis\": \"Zero-shot cross-model baseline: untuned DeepSeek-Coder-6.7B-Instruct similarly cannot reach SFT-level accuracy on exception_only verdict prediction, confirming SFT necessity is architecture-independent\", \"metrics\": {\"accuracy\": 0.9059, \"accuracy_ci_lower\": 0.8899, \"accuracy_ci_upper\": 0.9218, \"pass_precision\": 0.9743, \"pass_recall\": 0.8919, \"pass_f1\": 0.9313, \"fail_precision\": 0.7762, \"fail_recall\": 0.941, \"fail_f1\": 0.8507, \"n_test\": 1190, \"n_unknown\": 0}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/zeroshot_deepseek7b_exception_only/\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/zeroshot_deepseek7b_exception_only/eval_results.json\", \"spec\": {\"command\": \"python eval/zeroshot_eval.py --model_path DeepSeek-Coder-6.7B-Instruct --data_path exception_only_test.jsonl --gpu 0 (logit-based)\", \"server\": \"westd-11235\", \"data_path\": \"/root/trace-verdict-study/data/exception_only_test.jsonl\", \"data_count\": 1190, \"model_name\": \"DeepSeek-Coder-6.7B-Instruct\", \"seed\": 0}, \"completed_at\": \"2026-05-17T13:47:37.166Z\"}, \"zeroshot_qwen7b_exception_only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:00:40.251Z\", \"updated_at\": \"2026-05-17T13:47:19.462Z\", \"hypothesis\": \"Zero-shot prompting baseline: untuned Qwen2.5-7B-Instruct cannot match SFT accuracy (99.83%) on exception_only verdict prediction because distinguishing caught vs uncaught exceptions requires task-specific training signal, not just language understanding\", \"metrics\": {\"accuracy\": 0.8908, \"accuracy_ci_lower\": 0.8731, \"accuracy_ci_upper\": 0.9076, \"pass_precision\": 0.8815, \"pass_recall\": 0.9788, \"pass_f1\": 0.9276, \"fail_precision\": 0.9265, \"fail_recall\": 0.6696, \"fail_f1\": 0.7774, \"n_test\": 1190, \"n_unknown\": 0}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/zeroshot_qwen7b_exception_only/\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/zeroshot_qwen7b_exception_only/eval_results_mapped.json\", \"spec\": {\"command\": \"python eval/zeroshot_eval.py --model_path Qwen2.5-Coder-7B-Instruct --data_path exception_only_test.jsonl --gpu 0\", \"server\": \"westd-11235\", \"data_path\": \"/root/trace-verdict-study/data/exception_only_test.jsonl\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 0}, \"completed_at\": \"2026-05-17T13:47:19.462Z\"}, \"codellama13b_exception_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:47:18.896Z\", \"updated_at\": \"2026-05-17T13:06:57.551Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed42 --wandb_project trace-verdict-study --wandb_run_name codellama13b_exception_only_seed42 && python eval/evaluate.py --condition exception_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed42/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"271776\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_exception_only_seed42.log\", \"submitted_at\": \"2026-05-16T12:03:38.585Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 9885.3, \"gpu_hours\": 2.75}, \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"271776\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_exception_only_seed42.log\", \"wandb_run_id\": \"codellama13b_exception_only_seed42\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed42 --wandb_project trace-verdict-study --wandb_run_name codellama13b_exception_only_seed42 && python eval/evaluate.py --condition exception_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed42/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"codellama13b_exception_only_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T14:45:17.342Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T14:45:19.404390+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed42/final/\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9983, \"accuracy_ci_lower\": 0.9958, \"accuracy_ci_upper\": 1, \"pass_f1\": 0.9988, \"fail_f1\": 0.9971, \"n_test\": 1190}, \"completed_at\": \"2026-05-16T14:48:23.848Z\", \"hypothesis\": \"Cross-architecture validation: exception_only signal sufficiency (99.83% on Qwen-7B) generalizes to CodeLlama-13B because diagnostic content (exception type + location) is architecture-agnostic\", \"parent\": \"vota_exception_only_seed42_v2\"}, \"full_trace_tail_1024_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T08:13:21.880Z\", \"updated_at\": \"2026-05-17T10:30:11.408Z\", \"hypothesis\": \"Tail-1024 token budget: tests diminishing returns of tail context. If tail-1024 approaches tail-2048 (97.3%), 1024 tokens already captures nearly all diagnostic signal; the extra 1024 tokens add marginal value\", \"parent\": \"full_trace_tail_seed42\", \"spec\": {\"command\": \"python train/train_sft.py --condition full_trace_tail_1024 --truncation_side left --gradient_checkpointing --gpu 0 --seed 42 + eval\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"pid\": 340169, \"log_path\": \"~/runs/trace-verdict-study/full_trace_tail_1024_seed42.log\", \"submitted_at\": \"2026-05-17T08:20:01.416Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_tail_1024_{train,test}.jsonl\", \"data_count\": {\"train\": 4720, \"test\": 1190}, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_tail_1024_seed42\", \"checkpoint_source\": \"self-trained\", \"eval_data\": \"full_trace_tail_1024_test.jsonl\", \"tmux_session\": \"full_trace_tail_1024_seed42\", \"wall_clock_seconds\": 7810.0, \"gpu_hours\": 2.17}, \"metrics\": {\"accuracy\": 0.9647, \"accuracy_ci\": [0.9546, 0.9748], \"majority_baseline\": 0.7151, \"lift\": 0.2496, \"n\": 1190, \"pass_f1\": 0.9753, \"fail_f1\": 0.9381}, \"conclusion\": \"success\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_tail_1024_seed42.log\", \"completed_at\": \"2026-05-17T10:30:11.408Z\"}, \"full_trace_tail_256_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T08:13:21.000Z\", \"updated_at\": \"2026-05-17T10:30:10.501Z\", \"hypothesis\": \"Tail-256 token budget: tests if diagnostic signal is concentrated in the last 256 tokens. If tail-256 approaches tail-512 (93.6%), signal is extremely localized at trace end; if much lower, exception events need surrounding context for effective learning\", \"parent\": \"full_trace_tail_512_seed42\", \"spec\": {\"command\": \"python train/train_sft.py --condition full_trace_tail_256 --truncation_side left --gradient_checkpointing --gpu 0 --seed 42 + eval/evaluate.py\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"pid\": 339962, \"log_path\": \"~/runs/trace-verdict-study/full_trace_tail_256_seed42.log\", \"submitted_at\": \"2026-05-17T08:19:49.240Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_tail_256_{train,test}.jsonl\", \"data_count\": {\"train\": 4720, \"test\": 1190}, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_tail_256_seed42\", \"truncation\": \"tail-256 (keep last 256 tokens of trace)\", \"checkpoint_source\": \"self-trained\", \"eval_data\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_tail_256_test.jsonl\", \"wall_clock_seconds\": 7821.3, \"gpu_hours\": 2.17}, \"metrics\": {\"accuracy\": 0.7748, \"accuracy_ci\": [0.7496, 0.7975], \"majority_baseline\": 0.7151, \"lift\": 0.0597, \"n\": 1190, \"pass_f1\": 0.8333, \"fail_f1\": 0.6528}, \"conclusion\": \"negative\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_tail_256_seed42.log\", \"completed_at\": \"2026-05-17T10:30:10.501Z\"}, \"full_trace_tail_512_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T04:55:57.365Z\", \"updated_at\": \"2026-05-17T07:36:14.051Z\", \"hypothesis\": \"Tail-truncation token budget: if tail-2048 >> head-2048, tail-512 reveals how concentrated the signal is. tail-512 ≈ tail-2048 means signal is in last ~500 tokens; tail-512 << tail-2048 means more context needed beyond immediate exception event\", \"parent\": \"full_trace_tail_seed42\", \"spec\": {\"command\": \"python train/train_sft.py --condition full_trace_tail_512 --truncation_side left --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_tail_512_seed42 && python eval/evaluate.py --condition full_trace_tail_512 --checkpoint_dir .../final --gpu 0 --save_predictions\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"330357\", \"model_name\": \"Qwen/Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_tail_512_{train,test}.jsonl\", \"data_count\": 5910, \"submitted_at\": \"2026-05-17T05:03:00Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 9194.1, \"gpu_hours\": 2.55}, \"metrics\": {\"accuracy\": 0.936, \"accuracy_ci\": [0.922, 0.95], \"majority_baseline\": 0.7151, \"lift\": 0.221, \"n\": 1190, \"pass_precision\": 0.98, \"pass_recall\": 0.93, \"pass_f1\": 0.95, \"fail_precision\": 0.85, \"fail_recall\": 0.94, \"fail_f1\": 0.89}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_tail_512_seed42/final\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_tail_512_seed42.log\", \"completed_at\": \"2026-05-17T07:36:14.051Z\"}, \"full_trace_tail_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T04:08:51.116Z\", \"updated_at\": \"2026-05-17T07:36:13.099Z\", \"hypothesis\": \"Tail-truncation baseline: keeping the last 2048 tokens of full trace (where exception events concentrate) should significantly outperform head-truncation (81.76%) and approach exception_only (99.83%), validating that diagnostic signal is positionally concentrated at trace end\", \"parent\": \"full_trace_1024tok_seed42\", \"spec\": {\"command\": \"python train/train_sft.py --condition full_trace_tail --truncation_side left --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_tail_seed42 && python eval/evaluate.py --condition full_trace_tail --checkpoint_dir .../final --gpu 0 --save_predictions\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"327379\", \"model_name\": \"Qwen/Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_tail_{train,test}.jsonl\", \"data_count\": 5910, \"submitted_at\": \"2026-05-17T04:22:00Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 11653.1, \"gpu_hours\": 3.24}, \"metrics\": {\"accuracy\": 0.973, \"accuracy_ci\": [0.964, 0.982], \"majority_baseline\": 0.7151, \"lift\": 0.258, \"n\": 1190, \"pass_precision\": 0.98, \"pass_recall\": 0.99, \"pass_f1\": 0.98, \"fail_precision\": 0.97, \"fail_recall\": 0.94, \"fail_f1\": 0.95}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_tail_seed42/final\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_tail_seed42.log\", \"completed_at\": \"2026-05-17T07:36:13.099Z\"}, \"codellama13b_nomarker_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T02:09:08.956Z\", \"updated_at\": \"2026-05-17T03:23:43.036Z\", \"hypothesis\": \"Cross-architecture marker contribution: format markers ([No exception data in trace], [ERROR] prefix) contribute ~2pp on CodeLlama-13B as on Qwen family, confirming marker contribution is architecture-independent\", \"spec\": {\"command\": \"python train/train_sft.py --condition exception_only_nomarker --model_path /root/trace-verdict-study/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --gpu 0 --seed 42\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"322984\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_nomarker_seed42.log\", \"submitted_at\": \"2026-05-17T03:04:06.715Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_nomarker_train.jsonl\", \"data_count\": 4720, \"seed\": 42, \"wall_clock_seconds\": 1176.3, \"gpu_hours\": 0.33}, \"notes\": \"Cancelled by Director: model weights cleaned from disk, not worth re-downloading 26GB for speculative experiment. Worker re-submitted (PID 322984) before cancel order received — process killed. 论文 scope 已限定，Round 6 审稿人要求时再跑。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T03:23:43.036Z\"}, \"eval_missing_predictions_batch_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:41:02.286Z\", \"updated_at\": \"2026-05-17T02:58:57.381Z\", \"spec\": {\"command\": \"bash run_missing_predictions.sh 1\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"221213\", \"log_path\": \"~/runs/trace-verdict-study/eval_missing_predictions_batch_v2.log\", \"submitted_at\": \"2026-05-16T01:41:02.047Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"deepseek_full_trace_v3 + debugbench_vota predictions\", \"data_count\": 1616, \"model_name\": \"DeepSeek-Coder-6.7B + Qwen-2.5-Coder-7B\", \"seed\": 42, \"wall_clock_seconds\": 1905.5, \"gpu_hours\": 0.53}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (eval-only batch)\", \"completed_at\": \"2026-05-16T02:12:47.505Z\", \"hypothesis\": \"Utility: second batch re-evaluation pass for remaining checkpoints without predictions.jsonl, ensuring all DONE experiments have comparable evaluation outputs\"}, \"eval_missing_predictions_batch\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:33:51.923Z\", \"updated_at\": \"2026-05-17T02:58:56.080Z\", \"spec\": {\"command\": \"python eval/evaluate.py --save_predictions\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"219832\", \"log_path\": \"~/runs/trace-verdict-study/eval_missing_predictions_batch.log\", \"submitted_at\": \"2026-05-16T01:33:51.795Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/\", \"data_count\": 1616, \"model_name\": \"DeepSeek-Coder-6.7B + Qwen2.5-Coder-7B\", \"seed\": 42, \"wall_clock_seconds\": 1480.2, \"gpu_hours\": 0.41}, \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"/tmp/deepseek_eval_preds.log, /tmp/debugbench_vota_eval_preds.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T01:58:31.993Z\", \"notes\": \"predictions.jsonl generated for both experiments. deepseek_full_trace_seed42_v3: 1190 lines, accuracy=28.5% (NOT 79.16% as expected — model predicts all fail, same result with max_length=16384). debugbench_vota_seed42: 426 lines, accuracy=99.77% (matches registry). Paths: /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_seed42_v3/final/predictions.jsonl, /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_vota/final/predictions.jsonl\", \"hypothesis\": \"Utility: batch re-evaluation of checkpoints missing predictions.jsonl to complete provenance records and enable systematic cross-experiment comparison\"}, \"full_trace_1024tok_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:27:17.607Z\", \"updated_at\": \"2026-05-17T02:58:46.678Z\", \"spec\": {\"hypothesis\": \"plan_006: trace length ablation - 1024 tokens. Tests if medium-length trace preserves enough signal to match or exceed untruncated full_trace (81.8%).\", \"model_name\": \"Qwen/Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_{train,test}.jsonl\", \"data_count\": 4720, \"max_trace_tokens\": 1024, \"plan_id\": \"plan_006\", \"command\": \"train_sft.py --condition full_trace --max_trace_tokens 1024 + evaluate.py\", \"server\": \"westd-11235\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_1024tok\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_1024tok_seed42.log\"}, \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-16T00:15:42.746Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --max_trace_tokens 1024 --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_1024tok --wandb_project trace-verdict-study --wandb_run_name full_trace_1024tok_seed42 && python eval/evaluate.py --condition full_trace --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_1024tok/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_1024tok/final/eval_results.json\\\"\", \"wandb_run_id\": \"full_trace_1024tok_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T01:54:26.200Z\", \"training_hours\": 1.65}, \"pid\": \"212643\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_1024tok_seed42.log\", \"wandb_run_id\": \"full_trace_1024tok_seed42\", \"gpu_id\": \"cuda:0\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T01:54:27.781595+00:00\"}]}, \"metrics\": {\"accuracy\": 0.7723, \"majority_baseline\": 0.7151, \"lift\": 0.0571, \"n\": 1190, \"accuracy_ci\": [0.7487, 0.7958], \"pass_precision\": 0.9006, \"pass_recall\": 0.7662, \"pass_f1\": 0.8279, \"fail_precision\": 0.573, \"fail_recall\": 0.7876, \"fail_f1\": 0.6634, \"train_loss\": 0.0634, \"train_runtime_sec\": 5553, \"epochs\": 3}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-16T01:56:53.352Z\", \"hypothesis\": \"Token budget ablation (1024 tokens): near-full trace budget should approach no-limit accuracy (~81.76%), testing whether the last few hundred tokens contain marginal diagnostic value\", \"parent\": \"full_trace_seed42_v5\"}, \"full_trace_512tok_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:27:16.130Z\", \"updated_at\": \"2026-05-17T02:58:46.025Z\", \"spec\": {\"hypothesis\": \"plan_006: trace length ablation - 512 tokens. Tests accuracy with moderate trace length.\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen/Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"max_trace_tokens\": 512, \"plan_id\": \"plan_006\", \"command\": \"train_sft.py --condition full_trace --max_trace_tokens 512 --gradient_checkpointing --gpu 0 --seed 42 + evaluate.py\", \"server\": \"westd-11235\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_512tok/final\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_512tok_seed42.log\"}, \"reproduce\": {\"pid\": 197608, \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-15T23:16:13Z\", \"wandb_run_name\": \"full_trace_512tok_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\"}, \"metrics\": {\"accuracy\": 0.8042, \"majority_baseline\": 0.7151, \"lift\": 0.0891, \"pass_precision\": 0.8705, \"pass_recall\": 0.8531, \"pass_f1\": 0.8617, \"fail_precision\": 0.6489, \"fail_recall\": 0.6814, \"fail_f1\": 0.6647, \"n\": 1190, \"accuracy_ci\": [0.7815, 0.8261]}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-16T00:14:32.967Z\", \"hypothesis\": \"Token budget ablation (512 tokens): moderate truncation retains some diagnostic events but still loses critical tail information, yielding accuracy between 256-tok and full (no-limit) conditions\", \"parent\": \"full_trace_seed42_v5\"}, \"full_trace_256tok_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:27:14.119Z\", \"updated_at\": \"2026-05-17T02:58:45.053Z\", \"spec\": {\"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen/Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"max_trace_tokens\": 256}, \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T23:05:57.749Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --max_trace_tokens 256 --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_256tok --wandb_project trace-verdict-study --wandb_run_name full_trace_256tok_seed42 && python eval/evaluate.py --condition full_trace --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_256tok/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_256tok/final/eval_results.json\\\"\", \"wandb_run_id\": \"full_trace_256tok_seed42\", \"code_commit\": \"0836dd49526be55ab8571a3f716512d4ccd72312\", \"finished_at\": \"2026-05-16T00:01:15.610Z\", \"training_hours\": 0.92}, \"pid\": \"187860\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_256tok_seed42.log\", \"wandb_run_id\": \"full_trace_256tok_seed42\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T00:01:17.060104+00:00\"}]}, \"metrics\": {\"accuracy\": 0.7882, \"majority_baseline\": 0.7151, \"lift\": 0.0731, \"n\": 1190, \"pass_precision\": 0.903, \"pass_recall\": 0.788, \"pass_f1\": 0.842, \"fail_precision\": 0.597, \"fail_recall\": 0.788, \"fail_f1\": 0.679, \"accuracy_ci\": [0.764, 0.81], \"train_loss\": 0.1094, \"train_runtime_sec\": 3047, \"epochs\": 3}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_256tok/final\", \"completed_at\": \"2026-05-16T00:03:55.505Z\", \"hypothesis\": \"Token budget ablation (256 tokens): severely truncated full trace loses most diagnostic events, yielding accuracy near no-trace baseline because critical exception information is in the tail that gets cut\", \"parent\": \"full_trace_seed42_v5\"}, \"qwen15b_vota_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:22:02.463Z\", \"updated_at\": \"2026-05-17T02:58:44.124Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_vota_seed42 --wandb_project trace-verdict-study --wandb_run_name qwen15b_vota_seed42 && python eval/evaluate.py --condition vota --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_vota_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_vota_seed42/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"265006\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_vota_seed42.log\", \"submitted_at\": \"2026-05-16T10:15:27.340Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_vota_seed42/final\", \"wall_clock_seconds\": 3252.0, \"gpu_hours\": 0.9}, \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"265006\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_vota_seed42.log\", \"wandb_run_id\": \"qwen15b_vota_seed42\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_vota_seed42 --wandb_project trace-verdict-study --wandb_run_name qwen15b_vota_seed42 && python eval/evaluate.py --condition vota --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_vota_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_vota_seed42/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"qwen15b_vota_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T11:07:13.230Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T11:07:15.416174+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9958, \"n\": 1190, \"pass_recall\": 0.9976, \"fail_recall\": 0.9912, \"pass_f1\": 0.9971, \"fail_f1\": 0.9926, \"training_time_sec\": 2922}, \"completed_at\": \"2026-05-16T11:09:39.319Z\", \"hypothesis\": \"Scale invariance: VOTA compressed trace (99.41% on 7B) maintains near-perfect accuracy at 1.5B scale because diagnostic signals are explicitly surfaced, reducing model capacity requirements\", \"parent\": \"vota_seed42_v5\"}, \"qwen15b_nomarker_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T17:29:18.046Z\", \"updated_at\": \"2026-05-17T02:58:43.172Z\", \"spec\": {\"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"account\": \"root\", \"command\": \"cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition exception_only_nomarker --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 42\", \"pid\": \"292150\", \"log_path\": \"/tmp/qwen15b_nomarker_seed42.log\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_nomarker_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-1.5B-Instruct\", \"seed\": 42}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_nomarker/final/\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.978, \"n\": 1190, \"accuracy_ci\": [0.97, 0.986], \"majority_baseline\": 0.715, \"lift\": 0.263, \"pass_precision\": 0.97, \"pass_recall\": 1, \"pass_f1\": 0.98, \"fail_precision\": 1, \"fail_recall\": 0.92, \"fail_f1\": 0.96}, \"completed_at\": \"2026-05-16T17:47:36.397Z\", \"hypothesis\": \"Cross-scale nomarker validation: format marker contribution (~2pp at 7B) is consistent at 1.5B, confirming markers provide a small but architecture-and-scale-independent boost\", \"parent\": \"exception_only_nomarker_seed42\"}, \"qwen15b_no_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:22:01.028Z\", \"updated_at\": \"2026-05-17T02:58:42.232Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_no_trace_seed42 --wandb_project trace-verdict-study --wandb_run_name qwen15b_no_trace_seed42 && python eval/evaluate.py --condition no_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_no_trace_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_no_trace_seed42/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"263569\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_no_trace_seed42.log\", \"submitted_at\": \"2026-05-16T09:56:11.214Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_no_trace_seed42/final\", \"wall_clock_seconds\": 1138.8, \"gpu_hours\": 0.32}, \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"263569\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_no_trace_seed42.log\", \"wandb_run_id\": \"qwen15b_no_trace_seed42\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_no_trace_seed42 --wandb_project trace-verdict-study --wandb_run_name qwen15b_no_trace_seed42 && python eval/evaluate.py --condition no_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_no_trace_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_no_trace_seed42/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"qwen15b_no_trace_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T10:13:02.700Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T10:13:04.620520+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.6731, \"n\": 1190, \"pass_f1\": 0.7527, \"fail_f1\": 0.518, \"lift_over_majority\": -0.042, \"training_time_sec\": 851}, \"completed_at\": \"2026-05-16T10:15:10.018Z\", \"hypothesis\": \"Scale sensitivity of no-trace: without diagnostic signal, 1.5B model performs worse than 7B (75.13%) because code-structure-only heuristics require more capacity to learn effectively\", \"parent\": \"no_trace_seed42_v5\"}, \"qwen15b_full_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:22:03.743Z\", \"updated_at\": \"2026-05-17T02:58:41.323Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_seed42 --wandb_project trace-verdict-study --wandb_run_name qwen15b_full_trace_seed42 && python eval/evaluate.py --condition full_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_seed42/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"267886\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_full_trace_seed42.log\", \"submitted_at\": \"2026-05-16T11:10:01.431Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 3228.4, \"gpu_hours\": 0.9}, \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"267886\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_full_trace_seed42.log\", \"wandb_run_id\": \"qwen15b_full_trace_seed42\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_seed42 --wandb_project trace-verdict-study --wandb_run_name qwen15b_full_trace_seed42 && python eval/evaluate.py --condition full_trace --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_seed42/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"qwen15b_full_trace_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T12:00:28.907Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T12:00:31.043272+00:00\"}]}, \"metrics\": {\"accuracy\": 0.7706, \"n\": 1190}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_full_trace_seed42/final\", \"completed_at\": \"2026-05-16T12:03:49.820Z\", \"hypothesis\": \"Scale sensitivity of full_trace: noisy full trace (81.76% on 7B) degrades more at 1.5B because extracting signal from noise requires capacity that smaller models lack\", \"parent\": \"full_trace_seed42_v5\"}, \"qwen15b_exception_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:22:13.547Z\", \"updated_at\": \"2026-05-17T02:58:40.352Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed42 --wandb_project trace-verdict-study --wandb_run_name qwen15b_exception_only_seed42 && python eval/evaluate.py --condition exception_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed42/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"261588\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_exception_only_seed42.log\", \"submitted_at\": \"2026-05-16T09:22:34.937Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed42/final\", \"wall_clock_seconds\": 1990.3, \"gpu_hours\": 0.55}, \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"261588\", \"log_path\": \"~/runs/trace-verdict-study/qwen15b_exception_only_seed42.log\", \"wandb_run_id\": \"qwen15b_exception_only_seed42\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed42 --wandb_project trace-verdict-study --wandb_run_name qwen15b_exception_only_seed42 && python eval/evaluate.py --condition exception_only --model_path /root/autodl-tmp/models/Qwen2.5-Coder-1.5B-Instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed42/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/qwen15b_exception_only_seed42/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"qwen15b_exception_only_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T09:53:32.293Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T09:53:34.556600+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9983, \"accuracy_ci_lower\": 0.9958, \"accuracy_ci_upper\": 1, \"majority_baseline\": 0.7151, \"lift\": 0.283, \"n\": 1190, \"pass_precision\": 1, \"pass_recall\": 0.9976, \"pass_f1\": 0.9988, \"fail_precision\": 0.9941, \"fail_recall\": 1, \"fail_f1\": 0.9971, \"train_loss\": 0.1347, \"eval_loss\": 0.5761, \"wall_clock_seconds\": 1762}, \"completed_at\": \"2026-05-16T09:55:45.253Z\", \"hypothesis\": \"Scale invariance: exception_only signal sufficiency (99.83% on 7B) holds at 1.5B because high signal-to-noise ratio in exception traces requires minimal model capacity to exploit\", \"parent\": \"vota_exception_only_seed42_v2\"}, \"debugbench_vota_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:33:57.931Z\", \"updated_at\": \"2026-05-17T02:58:39.423Z\", \"spec\": {\"hypothesis\": \"plan_005: VOTA on DebugBench (bug detection). Tests if VOTA's structured trace analysis provides additional signal beyond exception_only on a logic-error-dominated benchmark.\", \"model_name\": \"Qwen/Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/debugbench_vota_{train,test}.jsonl\", \"data_count\": {\"train\": 1622, \"test\": 426}, \"plan_id\": \"plan_005\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && ... && python train/train_sft.py --condition debugbench_vota --gradient_checkpointing --gpu 0 --seed 42 --output_dir .../debugbench_vota --wandb_project trace-verdict-study --wandb_run_name debugbench_vota_seed42 && python eval/evaluate.py --condition debugbench_vota --checkpoint_dir .../debugbench_vota/final --gpu 0\\\"\", \"server\": \"westd-11235\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_vota\", \"log_path\": \"~/runs/trace-verdict-study/debugbench_vota_seed42.log\"}, \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-16T00:01:37.634Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition debugbench_vota --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_vota --wandb_project trace-verdict-study --wandb_run_name debugbench_vota_seed42 && python eval/evaluate.py --condition debugbench_vota --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_vota/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_vota/final/eval_results.json\\\"\", \"wandb_run_id\": \"debugbench_vota_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T00:55:26.974Z\", \"training_hours\": 0.9}, \"pid\": \"211253\", \"log_path\": \"~/runs/trace-verdict-study/debugbench_vota_seed42.log\", \"wandb_run_id\": \"debugbench_vota_seed42\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T00:55:28.620314+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9977, \"majority_baseline\": 0.5141, \"lift\": 0.4836, \"n\": 426, \"pass_precision\": 1, \"pass_recall\": 1, \"pass_f1\": 1, \"fail_precision\": 1, \"fail_recall\": 1, \"fail_f1\": 1, \"accuracy_ci\": [0.993, 1], \"train_loss\": 0.098, \"eval_loss\": 0.1179, \"eval_mean_token_accuracy\": 0.9737, \"errors\": 1}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T00:58:14.197Z\", \"notes\": \"predictions.jsonl generated (426 lines). Accuracy=99.77%, matches registry. Path: /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_vota/final/predictions.jsonl\", \"hypothesis\": \"DebugBench VOTA generalization: VOTA compressed trace maintains near-perfect accuracy on out-of-distribution bugs, confirming trace compression captures generalizable diagnostic patterns\", \"parent\": \"vota_seed42_v5\"}, \"debugbench_no_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:33:55.756Z\", \"updated_at\": \"2026-05-17T02:58:38.962Z\", \"spec\": {\"hypothesis\": \"plan_005: No-trace baseline on DebugBench. Establishes baseline for VOTA/exception_only comparison on bug detection task.\", \"model_name\": \"Qwen/Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/debugbench_no_trace_{train,test}.jsonl\", \"data_count\": {\"train\": 1622, \"test\": 426}, \"plan_id\": \"plan_005\", \"server\": \"westd-11235\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_no_trace\", \"log_path\": \"~/runs/trace-verdict-study/debugbench_no_trace_seed42.log\"}, \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-16T00:58:18.036Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition debugbench_no_trace --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_no_trace --wandb_project trace-verdict-study --wandb_run_name debugbench_no_trace_seed42 && python eval/evaluate.py --condition debugbench_no_trace --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_no_trace/final --gpu 0 --save_predictions --output /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_no_trace/final/eval_results.json\\\"\", \"wandb_run_id\": \"debugbench_no_trace_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T01:09:14.222Z\", \"training_hours\": 0.18}, \"pid\": \"215223\", \"log_path\": \"~/runs/trace-verdict-study/debugbench_no_trace_seed42.log\", \"wandb_run_id\": \"debugbench_no_trace_seed42\", \"gpu_id\": \"cuda:1\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T01:09:16.070113+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9671, \"majority_baseline\": 0.5141, \"lift\": 0.4531, \"pass_precision\": 1, \"pass_recall\": 0.936, \"pass_f1\": 0.967, \"fail_precision\": 0.937, \"fail_recall\": 1, \"fail_f1\": 0.967, \"accuracy_ci\": [0.948, 0.984], \"train_loss\": 0.249, \"eval_loss\": 0.532}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T01:12:05.904Z\", \"hypothesis\": \"DebugBench no-trace baseline: without execution trace, model relies on code structure alone — on DebugBench (50/50 pass/fail) this yields higher lift than HumanEval (71.5% majority) but still far below trace conditions\", \"parent\": \"no_trace_seed42_v5\"}, \"debugbench_exception_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:33:52.790Z\", \"updated_at\": \"2026-05-17T02:58:38.028Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition debugbench_exception_only --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_exception_only --wandb_project trace-verdict-study --wandb_run_name debugbench_exception_only_seed42 && python eval/evaluate.py --condition debugbench_exception_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_exception_only/final --gpu 0 --save_predictions --output /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_exception_only/final/eval_results.json\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"216806\", \"log_path\": \"~/runs/trace-verdict-study/debugbench_exception_only_seed42.log\", \"submitted_at\": \"2026-05-16T01:11:57.937Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1255.3, \"gpu_hours\": 0.35}, \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"216806\", \"log_path\": \"~/runs/trace-verdict-study/debugbench_exception_only_seed42.log\", \"wandb_run_id\": \"debugbench_exception_only_seed42\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition debugbench_exception_only --gradient_checkpointing --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_exception_only --wandb_project trace-verdict-study --wandb_run_name debugbench_exception_only_seed42 && python eval/evaluate.py --condition debugbench_exception_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_exception_only/final --gpu 0 --save_predictions --output /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_exception_only/final/eval_results.json\\\"\", \"wandb_run_id\": \"debugbench_exception_only_seed42\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T01:27:40.798Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T01:27:43.171585+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 1, \"majority_baseline\": 0.5141, \"lift\": 0.4859, \"n\": 426, \"pass_precision\": 1, \"pass_recall\": 1, \"pass_f1\": 1, \"fail_precision\": 1, \"fail_recall\": 1, \"fail_f1\": 1, \"accuracy_ci_wilson\": [0.9914, 1], \"accuracy_ci_bootstrap\": [1, 1], \"train_loss\": 0.2435, \"eval_loss\": 0.4157, \"train_runtime_sec\": 837}, \"notes\": \"100.0% accuracy (426/426 完美预测)。exception_only 在 DebugBench 上超越 VOTA (99.77%) 和 no_trace (96.71%)。Checkpoint: /root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_exception_only/final/。Predictions: predictions.jsonl (426条)。\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_exception_only/final/\", \"completed_at\": \"2026-05-16T01:32:53.272Z\", \"predictions_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/debugbench_exception_only/final/predictions.jsonl\", \"hypothesis\": \"Out-of-distribution generalization: exception_only signal sufficiency transfers to DebugBench (different bug categories, different code styles) because exception events carry universal diagnostic information regardless of bug origin\", \"parent\": \"vota_exception_only_seed42_v2\"}, \"deepseek_full_trace_seed42_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:40:07.877Z\", \"updated_at\": \"2026-05-17T02:58:37.133Z\", \"hypothesis\": \"DeepSeek full_trace v3: retrain with label-preserving truncation fix in to_chat_text(). v1/v2 collapsed due to DeepSeek tokenizer producing >2048 tokens → SFTTrainer right-truncated labels. Tests if full_trace shows intermediate performance on DeepSeek (plan_004, 4th condition).\", \"parent\": \"deepseek_full_trace_seed42\", \"notes\": \"DeepSeek full_trace v3: label-preserving truncation fix. 79.16% confirmed with max_length=2048 (matches training). eval_results.json has stale 28.49% from max_length=16384 run; correct value in eval_results_maxlen2048.json. predictions.jsonl overwritten 2026-05-16 with maxlen2048 results (reliable). Systematic audit 2026-05-16 confirmed: adapter base_model=DeepSeek, no model mixup possible (dimension mismatch would crash).\", \"spec\": {\"command\": \"python train_sft.py --condition full_trace --model deepseek-coder-6.7b --max_length 2048 --seed 42\", \"server\": \"westd-11235\", \"data_path\": \"/root/trace-verdict-study/data\", \"data_count\": 5910, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_seed42_v3\", \"log_path\": \"/root/trace-verdict-study/logs/deepseek_full_trace_seed42_v3\"}, \"gpu\": \"cuda:1\", \"metrics\": {\"accuracy\": 0.7916, \"majority_baseline\": 0.7151, \"lift\": 0.0765, \"n\": 1190, \"pass_precision\": 0.857, \"pass_recall\": 0.851, \"pass_f1\": 0.854, \"fail_precision\": 0.632, \"fail_recall\": 0.643, \"fail_f1\": 0.637, \"accuracy_ci\": [0.768, 0.813], \"train_loss\": 0.0547, \"train_runtime_seconds\": 8891, \"epochs\": 3, \"reeval_discrepancy\": {\"reeval_accuracy\": 0.285, \"reeval_note\": \"RESOLVED: 28.5% was caused by eval max_length=16384 (OOD). Re-eval with max_length=2048 reproduces 79.16%. predictions.jsonl updated to maxlen2048 results.\", \"status\": \"RESOLVED\"}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T23:27:54.219Z\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_seed42_v3.log\"}, \"loop_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T06:03:36.673Z\", \"updated_at\": \"2026-05-17T02:56:52.417Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition loop_only --gradient_checkpointing --gpu 0 --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed456 --wandb_project trace-verdict-study --wandb_run_name loop_only_seed456 && python eval/evaluate.py --condition loop_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed456/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed456/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"269723\", \"log_path\": \"~/runs/trace-verdict-study/loop_only_seed456.log\", \"submitted_at\": \"2026-05-16T11:31:50.484Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7892.7, \"gpu_hours\": 2.19}, \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"269723\", \"log_path\": \"~/runs/trace-verdict-study/loop_only_seed456.log\", \"wandb_run_id\": \"loop_only_seed456\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition loop_only --gradient_checkpointing --gpu 0 --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed456 --wandb_project trace-verdict-study --wandb_run_name loop_only_seed456 && python eval/evaluate.py --condition loop_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed456/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed456/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"loop_only_seed456\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T13:39:35.472Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T13:39:37.576842+00:00\"}]}, \"metrics\": {\"accuracy\": 0.8664, \"n\": 1190, \"pass_precision\": 0.9179, \"pass_recall\": 0.8931, \"pass_f1\": 0.9053, \"fail_precision\": 0.7486, \"fail_recall\": 0.7994, \"fail_f1\": 0.7732, \"accuracy_ci\": [0.847, 0.884], \"seed_comparison\": {\"seed42_accuracy\": 0.8563, \"seed123_accuracy\": 0.8588, \"seed456_accuracy\": 0.8664, \"mean_accuracy\": 0.8605, \"std\": 0.0053, \"note\": \"3-seed mean = 86.05% ± 0.53%. Moderate variance, seed456 best. loop_only is weakest trace condition (vs exception_only 99.83%, ae_only 99.64%, vota 99.41%).\"}}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed456/final\", \"completed_at\": \"2026-05-16T13:43:23.144Z\", \"notes\": \"Loop_only seed robustness 完成: seed42=85.63%, seed123=85.88%, seed456=86.64%. Mean=86.05% ± 0.43. 稳定。\", \"hypothesis\": \"Seed robustness of loop_only: loop behavioral patterns alone yield ~85% accuracy consistently across seeds, confirming loop_only is a moderate-signal condition independent of initialization\", \"parent\": \"vota_loop_only_seed42\"}, \"loop_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T06:03:35.196Z\", \"updated_at\": \"2026-05-17T02:56:51.920Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition loop_only --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed123 --wandb_project trace-verdict-study --wandb_run_name loop_only_seed123 && python eval/evaluate.py --condition loop_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed123/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"261213\", \"log_path\": \"~/runs/trace-verdict-study/loop_only_seed123.log\", \"submitted_at\": \"2026-05-16T09:21:29.194Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed123/final\", \"wall_clock_seconds\": 7779.8, \"gpu_hours\": 2.16}, \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"261213\", \"log_path\": \"~/runs/trace-verdict-study/loop_only_seed123.log\", \"wandb_run_id\": \"loop_only_seed123\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition loop_only --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed123 --wandb_project trace-verdict-study --wandb_run_name loop_only_seed123 && python eval/evaluate.py --condition loop_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only_seed123/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"loop_only_seed123\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T11:28:44.218Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T11:28:46.379629+00:00\"}]}, \"metrics\": {\"accuracy\": 0.8588, \"majority_baseline\": 0.7151, \"lift\": 0.1437, \"n\": 1190, \"pass_precision\": 0.9129, \"pass_recall\": 0.8872, \"pass_f1\": 0.8999, \"fail_precision\": 0.7355, \"fail_recall\": 0.7876, \"fail_f1\": 0.7607, \"accuracy_ci\": [0.8403, 0.8773]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T11:31:09.027Z\", \"notes\": \"Loop_only seed robustness 完成: seed42=85.63%, seed123=85.88%, seed456=86.64%. Mean=86.05% ± 0.43. 稳定。\", \"hypothesis\": \"Seed robustness of loop_only: loop behavioral patterns alone yield ~85% accuracy consistently across seeds, confirming loop_only is a moderate-signal condition independent of initialization\", \"parent\": \"vota_loop_only_seed42\"}, \"ae_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T03:41:51.316Z\", \"updated_at\": \"2026-05-17T02:56:50.865Z\", \"hypothesis\": \"Seed robustness: ae_only with seed=456 on Qwen-2.5-Coder-7B. Verifies ae_only 99.92% is stable across seeds (Reviewer P0 requirement).\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition ae_only --gradient_checkpointing --gpu 0 --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/ae_only_seed456 --wandb_project trace-verdict-study --wandb_run_name ae_only_seed456 && python eval/evaluate.py --condition ae_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/ae_only_seed456/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/ae_only_seed456/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/ae_only_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/ae_only_seed456/final\", \"log_path\": \"/tmp/ae_only_seed456.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T06:26:31.454Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T06:26:32.421Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:26:34.050811+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9992, \"n\": 1190, \"majority_baseline\": 0.7151, \"lift\": 0.2841, \"seed_comparison\": {\"seed42_accuracy\": 0.9992, \"seed123_accuracy\": 0.9908, \"seed456_accuracy\": 0.9992, \"mean_accuracy\": 0.9964, \"std\": 0.0049, \"note\": \"2/3 seeds = 99.92%, seed123 = 99.08%. Mean = 99.64% ± 0.49\"}}, \"parent\": \"vota_ae_only_seed42\"}, \"ae_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T03:41:50.753Z\", \"updated_at\": \"2026-05-17T02:56:49.985Z\", \"hypothesis\": \"Seed robustness: ae_only with seed=123 on Qwen-2.5-Coder-7B. Verifies ae_only 99.92% is stable across seeds (Reviewer P0 requirement).\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition ae_only --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/ae_only_seed123 --wandb_project trace-verdict-study --wandb_run_name ae_only_seed123 && python eval/evaluate.py --condition ae_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/ae_only_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/ae_only_seed123/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/ae_only_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/ae_only_seed123\", \"log_path\": \"/tmp/ae_only_seed123.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T06:16:31.845Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T06:16:33.018Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T06:16:35.841653+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9908, \"n\": 1190, \"pass_recall\": 0.987, \"fail_recall\": 1, \"majority_baseline\": 0.7151, \"lift\": 0.2757}, \"notes\": \"Cron 误判为 failed（进程死亡 5× 无 sentinel/W&B），Reviewer 独立核实训练+eval 均成功完成。accuracy=99.08% 低于 seed42/456 (99.92%)，ae_only 3-seed mean=99.64% ± 0.49。\", \"parent\": \"vota_ae_only_seed42\"}, \"exception_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:31:02.005Z\", \"updated_at\": \"2026-05-17T02:56:49.009Z\", \"spec\": {\"plan_id\": \"plan_008a\", \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_{train,test}.jsonl\", \"data_count\": 4720, \"server\": \"westd-11235\"}, \"hypothesis\": \"Seed robustness: exception_only with seed=456 on Qwen-2.5-Coder-7B (plan_008). Verifies headline result 99.83% is stable across seeds.\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-15T16:38:44.142Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --gradient_checkpointing --gpu 0 --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_seed456 --wandb_project trace-verdict-study --wandb_run_name exception_only_seed456 && python eval/evaluate.py --condition exception_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_seed456/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_seed456/final/eval_results.json\\\"\", \"wandb_run_id\": \"exception_only_seed456\", \"finished_at\": \"2026-05-15T17:56:16.196Z\", \"training_hours\": 1.29}, \"pid\": \"129476\", \"log_path\": \"~/runs/trace-verdict-study/exception_only_seed456.log\", \"wandb_run_id\": \"exception_only_seed456\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:56:17.874949+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9983, \"accuracy_ci\": [0.9958, 1], \"majority_baseline\": 0.7151, \"lift\": 0.2832, \"n\": 1190, \"pass_precision\": 1, \"pass_recall\": 0.9976, \"pass_f1\": 0.9988, \"fail_precision\": 0.9941, \"fail_recall\": 1, \"fail_f1\": 0.9971, \"vs_seed42\": {\"seed42_accuracy\": 0.9983, \"seed456_accuracy\": 0.9983, \"diff\": 0, \"note\": \"identical accuracy to 4 decimal places; no predictions.jsonl for paired bootstrap\"}, \"train_loss\": 0.1087, \"eval_loss\": 0.4629, \"train_runtime_sec\": 4541, \"epochs\": 3}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_seed456/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T17:58:25.389Z\", \"notes\": \"Seed robustness 结论: exception_only 99.83% ± 0.00 (seeds 42/123/456), 每 seed 恰好 2/1190 errors。极大概率同一组 irreducible 样本。\", \"parent\": \"vota_exception_only_seed42_v2\"}, \"exception_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:31:01.555Z\", \"updated_at\": \"2026-05-17T02:56:48.058Z\", \"spec\": {\"plan_id\": \"plan_008a\", \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 123, \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_{train,test}.jsonl\", \"data_count\": 4720, \"server\": \"westd-11235\"}, \"hypothesis\": \"Seed robustness: exception_only with seed=123 on Qwen-2.5-Coder-7B (plan_008). Verifies headline result 99.83% is stable across seeds.\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T15:54:06.157Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_seed123 --wandb_project trace-verdict-study --wandb_run_name exception_only_seed123 && python eval/evaluate.py --condition exception_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_seed123/final/eval_results.json\\\"\", \"wandb_run_id\": \"exception_only_seed123\", \"finished_at\": \"2026-05-15T18:00:50.835Z\", \"training_hours\": 2.11}, \"pid\": \"124197\", \"log_path\": \"~/runs/trace-verdict-study/exception_only_seed123.log\", \"wandb_run_id\": \"exception_only_seed123\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:00:52.169672+00:00\"}]}, \"notes\": \"Seed robustness 结论: exception_only 99.83% ± 0.00 (seeds 42/123/456), 每 seed 恰好 2/1190 errors。极大概率同一组 irreducible 样本。\", \"metrics\": {\"accuracy\": 0.9983, \"accuracy_ci\": [0.9958, 1], \"majority_baseline\": 0.7151, \"lift\": 0.2832, \"n\": 1190, \"pass_precision\": 1, \"pass_recall\": 0.9976, \"pass_f1\": 0.9988, \"fail_precision\": 0.9941, \"fail_recall\": 1, \"fail_f1\": 0.9971, \"train_loss\": 0.1096, \"train_runtime_sec\": 7507, \"epochs\": 3, \"seed_comparison\": {\"seed42_accuracy\": 0.9983, \"seed456_accuracy\": 0.9983, \"seed123_accuracy\": 0.9983, \"max_diff\": 0, \"note\": \"identical accuracy to 4 decimal places across all 3 seeds (42/456/123); each has exactly 2/1190 errors; exception_only fully seed-robust\"}}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_seed123/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T18:03:37.166Z\", \"parent\": \"vota_exception_only_seed42_v2\"}, \"exception_only_nomarker_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:12:12.683Z\", \"updated_at\": \"2026-05-17T02:56:47.143Z\", \"spec\": {\"hypothesis\": \"Task G: Format marker ablation — seed=456. Remove [No exception data in trace] marker from exception_only and retrain. Tests whether format marker affects model judgment.\", \"parent\": \"exception_only_seed42\", \"plan_id\": \"round5_task_g\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_nomarker_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456}, \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-16T18:24:34.339Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only_nomarker --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --gradient_checkpointing --gpu 0 --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_nomarker_seed456 --wandb_project trace-verdict-study --wandb_run_name exception_only_nomarker_seed456 && python eval/evaluate.py --condition exception_only_nomarker --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_nomarker_seed456/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_nomarker_seed456/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"exception_only_nomarker_seed456\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T19:44:27.466Z\", \"training_hours\": 1.33}, \"pid\": \"296962\", \"log_path\": \"~/runs/trace-verdict-study/exception_only_nomarker_seed456.log\", \"wandb_run_id\": \"exception_only_nomarker_seed456\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T19:44:29.627669+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9807, \"n\": 1190, \"errors\": 23, \"ci_95\": [0.9712, 0.9871], \"pass_f1\": 0.9865, \"fail_f1\": 0.9658, \"pass_precision\": 0.9836, \"pass_recall\": 0.9894, \"fail_precision\": 0.9731, \"fail_recall\": 0.9587, \"lift_over_majority\": 0.266}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_nomarker_seed456/final\", \"completed_at\": \"2026-05-16T19:47:16.706Z\", \"hypothesis\": \"Seed robustness of nomarker ablation: format marker contribution (~2pp) is consistent across random seeds, not an artifact of specific LoRA initialization\", \"parent\": \"exception_only_nomarker_seed42\"}, \"exception_only_nomarker_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T07:12:11.533Z\", \"updated_at\": \"2026-05-17T02:56:41.485Z\", \"spec\": {\"hypothesis\": \"Task G: Format marker ablation — seed=123. Remove [No exception data in trace] marker from exception_only and retrain. Tests whether format marker affects model judgment.\", \"parent\": \"exception_only_seed42\", \"plan_id\": \"round5_task_g\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"account\": \"root\", \"command\": \"cd /root/trace-verdict-study && /root/miniconda3/bin/python train/train_sft.py --condition exception_only_nomarker --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --gradient_checkpointing --gpu 0 --seed 123\", \"pid\": \"294700\", \"log_path\": \"/tmp/nomarker_seed123.log\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_nomarker_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 123}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9832, \"n\": 1190, \"ci_95\": [0.9756, 0.9899], \"pass_f1\": 0.9882, \"fail_f1\": 0.9705, \"pass_precision\": 0.9882, \"pass_recall\": 0.9882, \"fail_precision\": 0.9705, \"fail_recall\": 0.9705, \"lift_over_majority\": 0.2681}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_nomarker/final\", \"completed_at\": \"2026-05-16T19:07:39.167Z\", \"hypothesis\": \"Seed robustness of nomarker ablation: format marker contribution (~2pp) is consistent across random seeds, not an artifact of specific LoRA initialization\", \"parent\": \"exception_only_nomarker_seed42\"}, \"exception_only_nomarker_seed42\": {\"status\": \"DONE\", \"retry_count\": 2, \"created_at\": \"2026-05-16T06:03:33.324Z\", \"updated_at\": \"2026-05-17T02:56:40.848Z\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"reproduce\": {\"finished_at\": \"2026-05-16T17:06:14.692Z\"}, \"completed_at\": \"2026-05-16T15:50:22.017Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T15:50:23.894246+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T17:06:17.875239+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"python train/train_sft.py --condition exception_only_nomarker --model_path models/Qwen2.5-Coder-7B-Instruct --gpu 0 --seed 42 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_nomarker_seed42 --wandb_run_name exception_only_nomarker_seed42 --gradient_checkpointing && python eval/evaluate.py --condition exception_only_nomarker --checkpoint_dir .../exception_only_nomarker_seed42/final --save_predictions\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_nomarker_{train,test}.jsonl\", \"data_count\": 5910, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_nomarker_seed42\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exception_only_nomarker_seed42_train.log\", \"gpu\": \"cuda:0\", \"tmux_session\": \"nomarker_seed42\", \"description\": \"R1-N1 control: exception_only with ALL bracket format markers removed\", \"markers_removed\": [\"[No exception data in trace]\", \"[ERROR] prefix\", \"[No trace available]\", \"[...trace truncated...]\"], \"train_samples\": 4720, \"test_samples\": 1190}, \"wandb_run_id\": \"exception_only_nomarker_seed42\", \"pid\": 287933, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9655, \"n\": 1190, \"accuracy_ci\": [0.955, 0.976]}, \"hypothesis\": \"Format marker ablation: removing [No exception data in trace] and [ERROR] prefix markers reduces accuracy by ~2pp, isolating semantic content contribution (~97%) from formatting cue contribution (~2%)\", \"parent\": \"vota_exception_only_seed42_v2\"}, \"codellama13b_exception_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T19:59:26.563Z\", \"updated_at\": \"2026-05-17T02:56:39.750Z\", \"spec\": {\"hypothesis\": \"CodeLlama-13B exception_only seed456 — 3-seed robustness validation for cross-family core claim\", \"parent\": \"codellama13b_exception_only_seed42\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 456, \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --gpu 0 --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed456 --wandb_project trace-verdict-study --wandb_run_name codellama13b_exception_only_seed456 && python eval/evaluate.py --condition exception_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed456/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed456/final/eval_results.json --save_predictions\\\"\", \"pid\": \"303301\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_exception_only_seed456.log\", \"submitted_at\": \"2026-05-16T19:59:26Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"wall_clock_seconds\": 9834.4, \"gpu_hours\": 2.73}, \"reproduce\": {\"finished_at\": \"2026-05-16T22:41:10.285Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T22:41:13.148200+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9983, \"n\": 1190, \"errors\": 2, \"pass_precision\": 1, \"pass_recall\": 0.9976, \"pass_f1\": 0.9988, \"fail_precision\": 0.9941, \"fail_recall\": 1, \"fail_f1\": 0.9971}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed456/final\", \"hypothesis\": \"CodeLlama-13B exception_only seed456 — 3-seed robustness: exception signal sufficiency is consistent across random initializations, achieving near-perfect accuracy regardless of seed\", \"completed_at\": \"2026-05-16T22:43:20.359Z\", \"parent\": \"codellama13b_exception_only_seed42\"}, \"codellama13b_exception_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T19:10:52.335Z\", \"updated_at\": \"2026-05-17T02:56:38.799Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed123 --wandb_project trace-verdict-study --wandb_run_name codellama13b_exception_only_seed123 && python eval/evaluate.py --condition exception_only --model_path /root/autodl-tmp/models/CodeLlama-13b-Instruct-hf --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed123/final/eval_results.json --save_predictions\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"299731\", \"log_path\": \"~/runs/trace-verdict-study/codellama13b_exception_only_seed123.log\", \"submitted_at\": \"2026-05-16T19:10:52.141Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"CodeLlama-13b-Instruct-hf\", \"seed\": 123, \"wall_clock_seconds\": 9933.3, \"gpu_hours\": 2.76}, \"reproduce\": {\"finished_at\": \"2026-05-16T21:53:40.177Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T21:53:43.651373+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 1, \"n\": 1190, \"errors\": 0, \"pass_precision\": 1, \"pass_recall\": 1, \"pass_f1\": 1, \"fail_precision\": 1, \"fail_recall\": 1, \"fail_f1\": 1, \"lift_over_majority\": 0.2849}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/codellama13b_exception_only_seed123/final\", \"hypothesis\": \"CodeLlama-13B exception_only seed123 — multi-seed robustness: exception signal sufficiency is not seed-dependent and achieves near-perfect accuracy regardless of LoRA initialization\", \"completed_at\": \"2026-05-16T21:56:25.436Z\", \"parent\": \"codellama13b_exception_only_seed42\"}, \"label_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:40:19.669Z\", \"updated_at\": \"2026-05-16T09:22:46.929Z\", \"hypothesis\": \"Seed robustness: label_only (full_trace + label-only loss) with seed=456 on Qwen-2.5-Coder-7B. Verifies label_only 86.22% stability across seeds.\", \"parent\": \"full_trace_label_only_seed42\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-16T05:31:03.019Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --label_only_loss --gradient_checkpointing --gpu 0 --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_label_only_seed456 --wandb_project trace-verdict-study --wandb_run_name label_only_seed456 && python eval/evaluate.py --condition full_trace --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_label_only_seed456/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_label_only_seed456/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"label_only_seed456\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T09:01:08.445Z\", \"training_hours\": 3.5}, \"spec\": {\"command\": \"python train/train_sft.py --condition full_trace --label_only_loss --gradient_checkpointing --gpu 0 --seed 456 + evaluate.py\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_{train,test}.jsonl\", \"data_count\": 5910, \"model_name\": \"Qwen/Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_label_only_seed456/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_label_only_seed456/final/eval_results.json\"}, \"pid\": \"249616\", \"log_path\": \"~/runs/trace-verdict-study/label_only_seed456.log\", \"wandb_run_id\": \"label_only_seed456\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T09:01:14.180779+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.859, \"n\": 1190, \"pass_recall\": 0.938, \"fail_recall\": 0.661, \"pass_f1\": 0.905, \"fail_f1\": 0.727}, \"completed_at\": \"2026-05-16T09:22:46.929Z\"}, \"label_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:40:18.683Z\", \"updated_at\": \"2026-05-16T09:01:41.007Z\", \"hypothesis\": \"Seed robustness: label_only (full_trace + label-only loss) with seed=123 on Qwen-2.5-Coder-7B. Verifies label_only 86.22% stability across seeds.\", \"parent\": \"full_trace_label_only_seed42\", \"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-16T05:31:02.488Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --label_only_loss --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_label_only_seed123 --wandb_project trace-verdict-study --wandb_run_name label_only_seed123 && python eval/evaluate.py --condition full_trace --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_label_only_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_label_only_seed123/final/eval_results.json --save_predictions\\\"\", \"wandb_run_id\": \"label_only_seed123\", \"code_commit\": \"e404237ccc765768e267d4d6fd3c89549dcf41a4\", \"finished_at\": \"2026-05-16T08:58:33.644Z\", \"training_hours\": 3.46}, \"spec\": {\"command\": \"python train/train_sft.py --condition full_trace --label_only_loss --gradient_checkpointing --gpu 0 --seed 123 + evaluate.py\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_{train,test}.jsonl\", \"data_count\": 5910, \"model_name\": \"Qwen/Qwen2.5-Coder-7B-Instruct\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_label_only_seed123/final\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_label_only_seed123/final/eval_results.json\"}, \"pid\": \"249124\", \"log_path\": \"~/runs/trace-verdict-study/label_only_seed123.log\", \"wandb_run_id\": \"label_only_seed123\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T08:58:35.632418+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.8706, \"n\": 1190, \"pass_recall\": 0.974, \"fail_recall\": 0.611, \"pass_f1\": 0.915, \"fail_f1\": 0.729}, \"completed_at\": \"2026-05-16T09:01:41.007Z\"}, \"regex_baseline_analysis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T03:43:17.799Z\", \"updated_at\": \"2026-05-16T04:08:29.402Z\", \"hypothesis\": \"Regex/heuristic baselines on exception_only test data. Tests if simple pattern matching can match SFT performance (Reviewer critical concern).\", \"conclusion\": \"success\", \"metrics\": {\"regex_B1_ERROR_presence\": 0.9345, \"regex_B2_Traceback\": 0.7151, \"regex_B3_any_keyword\": 0.9345, \"regex_B4_exception_type\": 0.9361, \"regex_B5_format_marker\": 0.9933, \"regex_B6_error_count_ge2\": 0.9202, \"sft_exception_only\": 0.9983, \"best_regex_gap_vs_sft\": -0.0622, \"B5_mcnemar_p\": 0.041, \"n\": 1190}, \"spec\": {\"checkpoint_path\": \"N/A (CPU analysis, no model)\", \"log_path\": \"N/A (CPU analysis)\"}, \"checkpoint_path\": \"N/A (analysis-only, no training)\", \"log_path\": \"N/A (analysis-only, no training)\", \"completed_at\": \"2026-05-16T04:08:09.296Z\"}, \"full_trace_2048tok_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:27:19.848Z\", \"updated_at\": \"2026-05-16T04:08:09.868Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --data_dir /root/autodl-tmp/trace-verdict-study-data/ --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_2048tok --max_trace_tokens 2048 --seed 42 --wandb_run_name full_trace_2048tok_seed42 --gradient_checkpointing && python eval/evaluate.py --condition full_trace --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_2048tok/final --gpu 0 --save_predictions --output /root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_2048tok/final/eval_results.json\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"220276\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_2048tok_seed42.log\", \"submitted_at\": \"2026-05-16T01:35:43.979Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 9136.0, \"gpu_hours\": 2.54}, \"conclusion\": \"killed\", \"notes\": \"Director 取消：max_trace_tokens=2048 经 chat template overhead 后有效 trace ~1970 tok，与 no_limit (max_length=2048 封顶) 几乎一致。Token length ablation 最终设计改为 256/512/1024/no_limit 四点。\", \"completed_at\": \"2026-05-16T04:07:59.930Z\"}, \"deepseek_vota_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:13:39.391Z\", \"updated_at\": \"2026-05-16T02:45:56.773Z\", \"hypothesis\": \"Multi-model validation: VOTA on DeepSeek-Coder-6.7B-Instruct (plan_004). Tests if VOTA's verdict accuracy advantage generalizes beyond Qwen2.5-Coder to DCSH's same base model.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota --gradient_checkpointing --gpu 0 --seed 42 --wandb_project trace-verdict-study --wandb_run_name deepseek_vota_seed42 && python eval/evaluate.py --condition vota --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota/final/eval_results.json\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"93484\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_vota_seed42.log\", \"submitted_at\": \"2026-05-15T10:45:36.891Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/vota_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota/final\", \"wall_clock_seconds\": 8839.9, \"gpu_hours\": 2.46}, \"reproduce\": {\"finished_at\": \"2026-05-15T13:06:46.525Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:06:47.175122+00:00\"}]}, \"metrics\": {\"accuracy\": 0.8445, \"majority_baseline\": 0.7151, \"lift\": 0.1294, \"accuracy_ci\": [0.826, 0.864], \"pass_precision\": 0.821, \"pass_recall\": 1, \"pass_f1\": 0.902, \"fail_precision\": 1, \"fail_recall\": 0.454, \"fail_f1\": 0.625, \"eval_loss_epoch1\": 0.0679, \"eval_loss_epoch2\": 0.095, \"eval_loss_epoch3\": 0.1121, \"final_train_loss\": 0.0522, \"epoch1_checkpoint_eval\": {\"accuracy\": 0.7815, \"accuracy_ci\": [0.76, 0.803], \"fail_recall\": 0.233, \"fail_precision\": 1, \"pass_recall\": 1, \"pass_precision\": 0.766, \"fail_f1\": 0.378, \"pass_f1\": 0.867, \"conclusion\": \"epoch3_final_is_better\"}, \"reeval_with_fixed_script\": {\"accuracy\": 0.16, \"accuracy_ci\": [0.139, 0.18], \"fail_f1\": 0.61, \"fail_precision\": 0.9, \"fail_recall\": 0.47, \"pass_f1\": 0.07, \"pass_precision\": 1, \"pass_recall\": 0.04, \"note\": \"CATASTROPHIC: re-eval with corrected evaluate.py shows 16% (vs original 84.45%). Model predicts fail for almost everything. Previous 84.45% may have been from buggy eval. NEEDS INVESTIGATION.\"}, \"group_analysis\": {\"train_truncated\": {\"n\": 1091, \"accuracy\": 0.8304, \"ci_95\": [0.8075, 0.8524], \"correct\": 906, \"incorrect\": 185, \"pass_accuracy\": 1, \"pass_n\": 822, \"fail_accuracy\": 0.3123, \"fail_n\": 269}, \"train_intact\": {\"n\": 99, \"accuracy\": 1, \"ci_95\": [1, 1], \"correct\": 99, \"incorrect\": 0, \"pass_accuracy\": 1, \"pass_n\": 29, \"fail_accuracy\": 1, \"fail_n\": 70}, \"fisher_exact\": {\"odds_ratio\": 0, \"p_value\": 0}, \"overall_accuracy\": 0.8445, \"max_length\": 2048, \"note\": \"Grouped by whether training sample content exceeded token budget (DeepSeek tokenizer, max_length=2048). Inference used full-length input (no truncation). All 185 errors from truncated group's fail class (fail_recall=31.2%). Intact group: 100% accuracy.\"}}, \"conclusion\": \"success\", \"log_path\": \"/root/runs/trace-verdict-study/deepseek_vota_seed42.log\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_vota/final\", \"completed_at\": \"2026-05-15T13:12:56.838Z\", \"notes\": \"DeepSeek VOTA: 84.45% confirmed with max_length=16384 (re-verified 2026-05-16, exact match). max_length=2048 gives 16% due to evaluate.py front-truncation removing \\\"Answer: \\\" suffix from 91.7% of inputs. Training-time eval used old script (no truncation). exception_only/no_trace unaffected (short inputs). Systematic audit 2026-05-16: adapter base_model=DeepSeek confirmed, no model mixup possible.\"}, \"deepseek_exception_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:19:31.586Z\", \"updated_at\": \"2026-05-16T01:16:41.387Z\", \"hypothesis\": \"Cross-model seed robustness: exception_only seed=456 on DeepSeek-Coder-6.7B. Third seed to determine if seed42 (99.83%) is outlier or seed123 (91.09%) is outlier.\", \"parent\": \"deepseek_exception_only_seed123\", \"spec\": {\"command\": \"python train/train_sft.py --condition exception_only --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_exception_only_seed456 --gradient_checkpointing --gpu 0 --seed 456 --wandb_project trace-verdict-study --wandb_run_name deepseek_exception_only_seed456\", \"server\": \"westd-11235\", \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 456, \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_{train,test}.jsonl\", \"data_count\": 4720, \"checkpoint_source\": \"N/A - training run\", \"eval_data\": \"N/A - training run\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T22:08:34.111Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:08:35.359157+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9933, \"majority_baseline\": 0.7151, \"lift\": 0.2782, \"n\": 1190, \"pass_precision\": 1, \"pass_recall\": 0.9906, \"pass_f1\": 0.9953, \"fail_precision\": 0.9769, \"fail_recall\": 1, \"fail_f1\": 0.9883, \"accuracy_ci\": [0.9882, 0.9975], \"train_loss\": 0.1225, \"eval_loss\": 0.4824, \"train_runtime_sec\": 6246, \"seed_comparison\": {\"seed42_accuracy\": 0.9933, \"seed456_accuracy\": 0.9933, \"seed123_accuracy\": 0.9109, \"note\": \"seed42 and seed456 identical (99.33%); seed123 outlier (91.09%). 2/3 seeds robust.\"}, \"epoch1_checkpoint_eval\": {\"accuracy\": 0.993, \"accuracy_ci\": [0.988, 0.997], \"fail_f1\": 0.99, \"fail_precision\": 0.98, \"fail_recall\": 1, \"pass_f1\": 1, \"pass_precision\": 1, \"pass_recall\": 0.99, \"conclusion\": \"epoch1 (99.3%) ≈ epoch3 (99.33%), 1 epoch convergence confirmed\"}}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_exception_only_seed456/final\", \"log_path\": \"/root/runs/trace-verdict-study/deepseek_exception_only_seed456.log\", \"conclusion\": \"success\", \"notes\": \"seed456 accuracy 99.33% = seed42 99.33%（完全一致）。seed123 (91.09%) 是离群值——2/3 seeds 在 DeepSeek 上稳定。Epoch1 checkpoint (checkpoint-148) 可用于 epoch1 eval。Eval 由 on_complete hook 的 eval 脚本 (PID 166680) 自动运行，结果写入 final/eval_results.json。\", \"completed_at\": \"2026-05-15T22:13:38.554Z\", \"outputs\": {\"predictions_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_exception_only_seed456/checkpoint-148/predictions.jsonl\"}}, \"deepseek_exception_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:17:07.674Z\", \"updated_at\": \"2026-05-16T01:16:38.239Z\", \"hypothesis\": \"Multi-model validation: exception_only on DeepSeek-Coder-6.7B-Instruct (plan_004). Tests if exception dominance (99.83% on Qwen) generalizes across models — the most valuable cross-model evidence.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_exception_only --gradient_checkpointing --gpu 0 --seed 42 --wandb_project trace-verdict-study --wandb_run_name deepseek_exception_only_seed42 && python eval/evaluate.py --condition exception_only --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_exception_only/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_exception_only/final/eval_results.json\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"107188\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_exception_only_seed42.log\", \"submitted_at\": \"2026-05-15T13:10:32.405Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 42, \"wall_clock_seconds\": 7358.8, \"gpu_hours\": 2.04}, \"reproduce\": {\"finished_at\": \"2026-05-15T15:06:51.643Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:06:52.877301+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_exception_only/final\", \"metrics\": {\"accuracy\": 0.9933, \"majority_baseline\": 0.7151, \"lift\": 0.2782, \"n\": 1190, \"pass_precision\": 1, \"pass_recall\": 0.9906, \"pass_f1\": 0.9953, \"fail_precision\": 0.9769, \"fail_recall\": 1, \"fail_f1\": 0.9883, \"epoch1_checkpoint_eval\": {\"accuracy\": 0.9983, \"fail_recall\": 1, \"fail_precision\": 0.9941, \"pass_recall\": 0.9976, \"conclusion\": \"epoch1_better_by_0.50pp\"}}, \"completed_at\": \"2026-05-15T15:13:11.215Z\", \"notes\": \"epoch 1 (step 148) accuracy = 99.83%，高于 final (epoch 3) 的 99.33%。eval_loss epoch 2→3 从 0.413 涨到 0.476 (+15%)。continued training 导致 token-level 过拟合，verdict accuracy 从 99.83% 降到 99.33% (-0.50pp)。这是 eval_loss/accuracy 解耦的又一例证——但此处 eval_loss 上升确实伴随 accuracy 下降，与 DeepSeek VOTA 的趋势相反。Epoch 1 的 99.83% 与 Qwen exception_only (99.83%) 完全一致——跨模型 gap = 0pp（在最佳 checkpoint 下）。\", \"outputs\": {\"predictions_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_exception_only/checkpoint-148/predictions.jsonl\"}}, \"deepseek_no_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:13:40.004Z\", \"updated_at\": \"2026-05-16T01:16:37.143Z\", \"hypothesis\": \"Multi-model baseline: no-trace verdict prediction on DeepSeek-Coder-6.7B-Instruct (plan_004). Establishes DeepSeek baseline for comparison with VOTA and full_trace conditions.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_no_trace --gradient_checkpointing --gpu 0 --seed 42 --wandb_project trace-verdict-study --wandb_run_name deepseek_no_trace_seed42 && python eval/evaluate.py --condition no_trace --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_no_trace/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_no_trace/final/eval_results.json\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"106822\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_no_trace_seed42.log\", \"submitted_at\": \"2026-05-15T13:09:35.611Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/no_trace_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 42, \"wall_clock_seconds\": 1791.4, \"gpu_hours\": 0.5}, \"reproduce\": {\"finished_at\": \"2026-05-15T13:37:07.125Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:37:08.315605+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"accuracy\": 0.7336, \"majority_baseline\": 0.7151, \"lift\": 0.0185, \"n\": 1190, \"pass_precision\": 0.817, \"pass_recall\": 0.808, \"pass_f1\": 0.813, \"fail_precision\": 0.532, \"fail_recall\": 0.546, \"fail_f1\": 0.539, \"accuracy_ci\": [0.708, 0.757], \"lift_ci\": [-0.009, 0.046]}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_no_trace/final\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_no_trace_seed42.log\", \"completed_at\": \"2026-05-15T13:39:27.031Z\", \"notes\": \"Negative: lift +1.85pp over majority, 95% CI [-0.93, +4.63] crosses 0. DeepSeek-Coder-6.7B no-trace verdict prediction is not statistically different from majority baseline. Within-model VOTA lift: +11.09pp (84.45% - 73.36%).\", \"outputs\": {\"predictions_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_no_trace/final/predictions.jsonl\"}}, \"debugbench_exception_bug_fix\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:14:24.382Z\", \"updated_at\": \"2026-05-15T23:26:16.029Z\", \"spec\": {\"command\": \"python data/debugbench_format_data.py\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/debugbench/raw_traces.jsonl\", \"data_count\": 2048, \"model_name\": \"data_processing\", \"seed\": 42, \"checkpoint_path\": \"/root/trace-verdict-study/data/debugbench_format_data.py\", \"log_path\": \"/tmp/debugbench_format.log\"}, \"conclusion\": \"success\", \"hypothesis\": \"BUG FIX: compress_exception_only() only checked trace_raw events, missing 625/1006 empty-trace fails (syntax errors) + 5 event-capped samples. Fix: fallback to test_results.error. Exception signal 376→1006/1006, upper bound 69.2%→100%. DebugBench 30.5% empty trace rate confirmed.\", \"completed_at\": \"2026-05-15T23:26:16.029Z\"}, \"vota_seed456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:39:05.494Z\", \"updated_at\": \"2026-05-15T21:04:28.008Z\", \"hypothesis\": \"Seed robustness: VOTA with seed=456, retry with --gradient_checkpointing (v1 OOM). Verifies VOTA 99.2% accuracy stable across seeds.\", \"notes\": \"Auto-retried from vota_seed456 (OOM). PID 146592, cuda:1, --gradient_checkpointing enabled. Started 18:31 UTC, ~2h to complete. Low priority per Director (VOTA not primary claim).\", \"parent\": \"vota_seed456\", \"spec\": {\"command\": \"python train/train_sft.py --condition vota --gradient_checkpointing --gpu 0 --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/vota_seed456 --wandb_project trace-verdict-study --wandb_run_name vota_seed456_v2\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/vota_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"N/A (training, not eval)\", \"eval_data\": \"N/A (training, not eval)\"}, \"metrics\": {\"accuracy\": 0.9908, \"pass_precision\": 1, \"pass_recall\": 0.987, \"pass_f1\": 0.993, \"fail_precision\": 0.969, \"fail_recall\": 1, \"fail_f1\": 0.984, \"ci_95\": [0.985, 0.996]}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/vota_seed456/final\", \"log_path\": \"/root/runs/trace-verdict-study/vota_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:04:28.008Z\"}, \"no_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:58:31.125Z\", \"updated_at\": \"2026-05-15T19:53:26.153Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export WANDB_API_KEY=[REDACTED] /root/.wandb_api_key 2>/dev/null || echo '') && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --gpu 0 --wandb_project trace-verdict-study --wandb_run_name no_trace_seed42\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"709277\", \"log_path\": \"~/runs/trace-verdict-study/no_trace_seed42.log\", \"submitted_at\": \"2026-05-14T17:58:31.124Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 93295.0, \"gpu_hours\": 25.92}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:53:26.153Z\"}, \"no_trace_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:59:53.488Z\", \"updated_at\": \"2026-05-15T19:53:25.181Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export WANDB_API_KEY=[REDACTED] /root/.wandb_api_key 2>/dev/null || echo '') && cd /root/trace-verdict-study && python train/train_sft.py --condition no_trace --gpu 0 --wandb_project trace-verdict-study --wandb_run_name no_trace_seed42\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"709781\", \"log_path\": \"~/runs/trace-verdict-study/no_trace_seed42_v2.log\", \"submitted_at\": \"2026-05-14T17:59:53.485Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 93211.7, \"gpu_hours\": 25.89}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:53:25.181Z\"}, \"vota_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:58:32.967Z\", \"updated_at\": \"2026-05-15T19:53:23.979Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export WANDB_API_KEY=[REDACTED] /root/.wandb_api_key 2>/dev/null || echo '') && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --gpu 1 --wandb_project trace-verdict-study --wandb_run_name vota_seed42\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"709357\", \"log_path\": \"~/runs/trace-verdict-study/vota_seed42.log\", \"submitted_at\": \"2026-05-14T17:58:32.964Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 93291.0, \"gpu_hours\": 25.91}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:53:23.979Z\"}, \"vota_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:59:55.517Z\", \"updated_at\": \"2026-05-15T19:53:22.853Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export WANDB_API_KEY=[REDACTED] /root/.wandb_api_key 2>/dev/null || echo '') && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --gpu 1 --wandb_project trace-verdict-study --wandb_run_name vota_seed42\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"709863\", \"log_path\": \"~/runs/trace-verdict-study/vota_seed42_v2.log\", \"submitted_at\": \"2026-05-14T17:59:55.513Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 93207.3, \"gpu_hours\": 25.89}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:53:22.853Z\"}, \"vota_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:38:51.823Z\", \"updated_at\": \"2026-05-15T18:38:53.768Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --gradient_checkpointing --gpu 0 --seed 456 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/vota_seed456 --wandb_project trace-verdict-study --wandb_run_name vota_seed456_v2 && python eval/evaluate.py --condition vota --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/vota_seed456/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/vota_seed456/final/eval_results.json --save_predictions --max_length 2048\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"146582\", \"log_path\": \"~/runs/trace-verdict-study/vota_seed456.log\", \"submitted_at\": \"2026-05-15T18:31:33.049Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 87.5, \"gpu_hours\": 0.02}, \"hypothesis\": \"Seed robustness: VOTA with seed=456 (plan_008). Verifies VOTA 99.2% accuracy is stable across random seeds.\", \"notes\": \"Original PID 145908 OOM'd ~3min after start. Auto-retried as v2 (PID 146592) with --gradient_checkpointing on cuda:1. Step 15/444 (3.4%) at 18:37 UTC, ~2h to complete. W&B run: vota_seed456_v2. Director 决策: 低优先级，exception_only seed robustness 优先。\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T18:33:00.592Z\"}, \"deepseek_full_trace_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:13:29.181Z\", \"updated_at\": \"2026-05-15T18:27:46.453Z\", \"hypothesis\": \"DeepSeek full_trace v2: retrain with v5 code (chat-template-aware truncation preserving labels). v1 collapsed to 28.49% due to label truncation during training.\", \"spec\": {\"plan_id\": \"plan_004\", \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 42, \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_{train,test}.jsonl\", \"data_count\": 4720, \"server\": \"westd-11235\", \"command\": \"train_sft.py --condition full_trace + evaluate.py\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace_v2\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T18:27:40.446Z\", \"notes\": \"Killed by worker_ops_kill_and_submit_vota_seed456 to free cuda:1 for vota_seed456. Training incomplete — needs re-run after GPU available. PID 144864 killed at ~18:24 UTC.\"}, \"deepseek_full_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:13:40.756Z\", \"updated_at\": \"2026-05-15T18:23:42.993Z\", \"hypothesis\": \"Multi-model comparison: full-trace verdict prediction on DeepSeek-Coder-6.7B-Instruct (plan_004). Tests if full_trace also shows intermediate performance on DeepSeek-Coder.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace --gradient_checkpointing --gpu 0 --seed 42 --wandb_project trace-verdict-study --wandb_run_name deepseek_full_trace_seed42 && python eval/evaluate.py --condition full_trace --model_path /root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace/final/eval_results.json\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"112289\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_full_trace_seed42.log\", \"submitted_at\": \"2026-05-15T13:47:47.241Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"deepseek-ai/deepseek-coder-6.7b-instruct\", \"seed\": 42, \"wall_clock_seconds\": 10254.4, \"gpu_hours\": 2.85}, \"notes\": \"INVALIDATED: train-eval truncation mismatch。旧 eval (无截断): 28.49% (all predict fail)。修复后 eval (截断到 2048): 10.59% (模型输出垃圾 token: '{', 'execution', '{}', 'assert' 等, 从未输出 'pass')。结论：LoRA 本身训练失败，不仅是 eval 问题。truncation fix 暴露了更深层问题——训练时 label 被截断导致 LoRA 未学到有效分类行为。v2 重训已提交 (deepseek_full_trace_seed42_v2)。\", \"reproduce\": {\"finished_at\": \"2026-05-15T16:36:17.857Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T16:36:19.211594+00:00\"}]}, \"metrics\": {\"accuracy_no_truncation\": 0.2849, \"accuracy_with_truncation_fix\": 0.1059, \"accuracy_with_truncation_fix_ci\": [0.089, 0.123], \"majority_baseline\": 0.7151, \"n\": 1190, \"note\": \"Both evals show model failure. No-truncation: all predict fail. With-truncation: garbage tokens. LoRA training itself failed due to label truncation during training.\"}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_full_trace/final\", \"log_path\": \"~/runs/trace-verdict-study/deepseek_full_trace_seed42.log\", \"completed_at\": \"2026-05-15T16:38:41.604Z\"}, \"vota_exception_only_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:16:14.602Z\", \"updated_at\": \"2026-05-15T18:02:36.534Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --gradient_checkpointing --gpu 1 --seed 42 --wandb_project trace-verdict-study --wandb_run_name vota_exception_only_seed42_v2 && python eval/evaluate.py --condition exception_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only/final --gpu 1 --output /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only/final/eval_results.json\\\"\", \"server\": \"westd-11235\", \"data_path\": \"exception_only\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"pid\": \"79633\", \"gpu\": [\"cuda:1\"], \"submitted_at\": \"2026-05-15T15:15:14Z\", \"log_path\": \"~/runs/trace-verdict-study/vota_exception_only_seed42_v2.log\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/exception_only/final\"}, \"hypothesis\": \"VOTA component ablation: exception_only condition — retry with --gradient_checkpointing (v1 OOM at step 8). Tests if [ERROR] events are the primary driver of VOTA's 99.2% accuracy (plan_003 sub-b)\", \"metrics\": {\"accuracy\": 0.9983, \"majority_baseline\": 0.7151, \"lift\": 0.2832, \"n\": 1190, \"pass_precision\": 1, \"pass_recall\": 0.998, \"pass_f1\": 0.999, \"fail_precision\": 0.994, \"fail_recall\": 1, \"fail_f1\": 0.997, \"lift_vs_notrace\": 0.2471, \"lift_vs_notrace_ci_lower\": 0.2227, \"lift_vs_notrace_ci_upper\": 0.2714, \"lift_vs_fulltrace\": 0.1807, \"lift_vs_fulltrace_ci_lower\": 0.1588, \"lift_vs_fulltrace_ci_upper\": 0.2034, \"lift_vs_vota\": 0.0067, \"lift_vs_vota_ci_lower\": 0.0017, \"lift_vs_vota_ci_upper\": 0.0126, \"lift_vs_vota_pvalue\": 0.01}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T09:35:01.676Z\", \"notes\": \"Seed robustness confirmed: exception_only 99.83% ± 0.00 across seeds 42/123/456. Each seed has exactly 2/1190 errors. High probability same irreducible samples. [re-eval] 修复后 evaluate.py 重跑 Δ=0。\"}, \"vota_seed123\": {\"status\": \"DONE\", \"retry_count\": 2, \"created_at\": \"2026-05-15T12:38:48.954Z\", \"updated_at\": \"2026-05-15T16:58:40.507Z\", \"hypothesis\": \"Seed robustness: VOTA with seed=123 (plan_008). Verifies VOTA 99.2% accuracy is stable across random seeds.\", \"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-11235\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T12:39:38.117Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition vota --gradient_checkpointing --gpu 0 --seed 123 --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/vota_seed123 --wandb_project trace-verdict-study --wandb_run_name vota_seed123_v2 && python eval/evaluate.py --condition vota --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/vota_seed123/final --gpu 0 --output /root/autodl-tmp/trace-verdict-study-checkpoints/vota_seed123/final/eval_results.json\\\"\", \"finished_at\": \"2026-05-15T12:59:09.843Z\", \"training_hours\": 0.33, \"wandb_run_id\": \"vota_seed123_v2\"}, \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 4.64 GiB. GPU 0 has a total capacity of 94.97 GiB of which 614.25 MiB is free. Process 93494 has 21.86 GiB memory in use. Including non-PyTorch memory, this process has 24.48 GiB memory in use. Of the allocated m\", \"completed_at\": \"2026-05-15T12:42:01.260Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T12:42:02.205055+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T12:59:14.689674+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"conclusion\": \"failed\", \"spec\": {\"plan_id\": \"plan_008b\", \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 123, \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/vota_{train,test}.jsonl\", \"data_count\": 4720, \"server\": \"westd-11235\"}}, \"full_trace_label_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T04:01:29.625Z\", \"updated_at\": \"2026-05-15T16:36:05.917Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace_label_only/final\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_label_only_seed42.log\"}, \"hypothesis\": \"Label-only loss on full_trace fixes gradient dilution collapse (plan_002: loss only on pass/fail token, not trace tokens)\", \"reproduce\": {\"finished_at\": \"2026-05-15T07:15:28.991Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T07:15:30.057513+00:00\"}]}, \"metrics\": {\"accuracy\": 0.8622, \"accuracy_ci_lower\": 0.8437, \"accuracy_ci_upper\": 0.8807, \"majority_baseline\": 0.7151, \"lift\": 0.1471, \"n\": 1190, \"pass_precision\": 0.8821, \"pass_recall\": 0.9318, \"pass_f1\": 0.9063, \"fail_precision\": 0.8007, \"fail_recall\": 0.6873, \"fail_f1\": 0.7397, \"train_loss\": 0.2505, \"eval_loss\": 0.3205, \"lift_vs_notrace\": 0.1109, \"lift_vs_notrace_ci_lower\": 0.0849, \"lift_vs_notrace_ci_upper\": 0.137, \"lift_vs_standard_fulltrace\": 0.0445, \"lift_vs_standard_fulltrace_ci_lower\": 0.0235, \"lift_vs_standard_fulltrace_ci_upper\": 0.0655, \"lift_vs_standard_fulltrace_pvalue\": 0}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T07:23:57.111Z\", \"notes\": \"Label-only loss 将 full_trace 从 81.8% 提升到 86.2% (+4.4pp)，确认 gradient dilution 是 full_trace 性能受限的部分原因。但 86.2% vs VOTA 99.2% 仍有 13pp gap，说明 gradient dilution 只是部分解释——trace 信息密度（VOTA 的 decision-relevant compression）才是主因。[2026-05-15 re-eval] 用修复后 evaluate.py + --condition full_trace 重跑，accuracy 不变 (86.22% → 86.22%, Δ=0)，predictions.jsonl 1190行已生成。训练确认使用 full_trace 格式数据，label_only 仅改变 loss mask。\"}, \"vota_no_ae_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T04:21:27.279Z\", \"updated_at\": \"2026-05-15T16:25:20.610Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition vota_no_ae --gpu 1 --seed 42 --wandb_project trace-verdict-study --wandb_run_name vota_no_ae_seed42\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"953133\", \"log_path\": \"~/runs/trace-verdict-study/vota_no_ae_seed42.log\", \"submitted_at\": \"2026-05-15T04:21:27.215Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/vota_no_ae_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/vota_no_ae/final\", \"wall_clock_seconds\": 6902.4, \"gpu_hours\": 1.92}, \"hypothesis\": \"VOTA without actual/expected values: tests if VOTA's accuracy comes from genuine behavioral understanding vs trivial string comparison (plan_001)\", \"reproduce\": {\"finished_at\": \"2026-05-15T06:10:18.839Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T06:10:19.847891+00:00\"}]}, \"metrics\": {\"accuracy\": 0.994, \"majority_baseline\": 0.7151, \"lift\": 0.279, \"n\": 1190, \"pass_f1\": 0.996, \"fail_f1\": 0.989, \"accuracy_ci_lower\": 0.989, \"accuracy_ci_upper\": 0.998, \"lift_vs_notrace\": 0.243, \"lift_vs_notrace_ci_lower\": 0.218, \"lift_vs_notrace_ci_upper\": 0.268, \"train_loss\": 0.0908, \"eval_loss\": 0.2215, \"wall_clock_seconds\": 6397.88}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:16:29.587Z\", \"notes\": \"✅ Eval verified: accuracy 99.4% [98.9, 99.8] confirmed by evaluate.py + bootstrap. 去掉 actual/expected 后性能不降（vs VOTA v5 99.2%），证明 VOTA 效果来自 trace 行为模式理解而非 trivial string comparison。Claim 1 走 full positive framing。[2026-05-15 re-eval] 用修复后 evaluate.py 重跑，accuracy 不变 (99.41% → 99.41%, Δ=0)，predictions.jsonl 1190行已生成。\"}, \"vota_loop_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:02:41.201Z\", \"updated_at\": \"2026-05-15T16:25:16.352Z\", \"hypothesis\": \"VOTA component ablation: loop_only condition — only loop compression summaries, no actual/expected or exception. Tests loop behavioral pattern contribution to VOTA 99.2% accuracy (plan_003 sub-c)\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition loop_only --gradient_checkpointing --gpu 0 --seed 42 --wandb_project trace-verdict-study --wandb_run_name vota_loop_only_seed42 && python eval/evaluate.py --condition loop_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/loop_only/final --gpu 0\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"82362\", \"log_path\": \"~/runs/trace-verdict-study/vota_loop_only_seed42.log\", \"submitted_at\": \"2026-05-15T07:58:06.023Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/loop_only_{train,test}.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"wall_clock_seconds\": 7952.5, \"gpu_hours\": 2.21}, \"reproduce\": {\"finished_at\": \"2026-05-15T10:04:53.052Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T10:04:54.341040+00:00\"}]}, \"metrics\": {\"accuracy\": 0.8563, \"majority_baseline\": 0.7151, \"lift\": 0.1412, \"n\": 1190, \"pass_precision\": 0.9239, \"pass_recall\": 0.8707, \"pass_f1\": 0.8966, \"fail_precision\": 0.7165, \"fail_recall\": 0.8201, \"fail_f1\": 0.7648, \"accuracy_ci\": [0.8353, 0.8756], \"bootstrap_vs_no_trace\": {\"diff\": 0.105, \"ci\": [0.0824, 0.1286], \"significant\": true}, \"bootstrap_vs_vota\": {\"diff\": -0.1378, \"ci\": [-0.1571, -0.1185], \"significant\": true}, \"bootstrap_vs_full_trace\": {\"diff\": 0.0387, \"ci\": [0.0185, 0.0597], \"significant\": true}, \"train_loss\": 0.0718, \"wall_clock_seconds\": 7425.65}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/loop_only/final/\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/loop_only/final/eval_results.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T10:10:38.549Z\", \"notes\": \"[2026-05-15 re-eval] 用修复后 evaluate.py 重跑，accuracy 不变 (85.63% → 85.63%, Δ=0)，predictions.jsonl 1190行已生成。\"}, \"vota_ae_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:11:44.999Z\", \"updated_at\": \"2026-05-15T16:25:14.973Z\", \"hypothesis\": \"VOTA component ablation: ae_only condition — only actual/expected values, no exception/loop compression (plan_003 sub-a)\", \"notes\": \"ae_only accuracy 99.92% [99.75%, 100%]。与 exception_only (99.83%) 统计等价，均为 Tier 1 diagnostic-moment signals。88% 样本含 fallback locals 行（无信息量的模块命名空间导入），85% 样本含 [ASSERT] 行的 actual/expected 对比（合法诊断信息）。Reviewer 核实 fallback locals 不含 verdict 信号，不构成 data leakage（D013 裁定）。Train: 3 epochs, 444 steps, final train_loss=0.022, eval_loss=0.166, eval_token_acc=96.76%。[2026-05-15 re-eval] 用修复后 evaluate.py 重跑，accuracy 不变 (99.92% → 99.92%, Δ=0)，predictions.jsonl 1190行已生成。\", \"spec\": {\"command\": \"python train/train_sft.py --condition ae_only --gradient_checkpointing --gpu 1 --seed 42 --wandb_project trace-verdict-study --wandb_run_name vota_ae_only_seed42 && python eval/evaluate.py --condition ae_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/ae_only/final --gpu 1 --output /root/autodl-tmp/trace-verdict-study-checkpoints/ae_only/final/eval_results.json\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/ae_only_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-15T12:13:36.539Z\"}, \"failure_reason\": \"N/A — cron 误判。实际已完成，eval_results.json 已生成。process dead 5x 是因为训练+eval 正常结束后进程退出，cron 无 W&B/sentinel 检测通道。\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T12:13:36.813Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T12:13:37.756005+00:00\"}]}, \"metrics\": {\"accuracy\": 0.9992, \"accuracy_ci\": [0.9975, 1], \"bootstrap_pairwise\": {\"ae_only_vs_no_trace\": {\"diff\": 0.2479, \"ci\": [0.2235, 0.2731], \"p_value\": 0, \"significant\": true}, \"ae_only_vs_exception_only\": {\"diff\": 0.0008, \"ci\": [-0.0017, 0.0034], \"p_value\": 0.8002, \"significant\": false}, \"ae_only_vs_vota\": {\"diff\": 0.005, \"ci\": [0.0017, 0.0092], \"p_value\": 0.0046, \"significant\": true}}, \"config\": {\"n_bootstrap\": 10000, \"seed\": 42, \"method\": \"paired_bootstrap\"}}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/ae_only/final\", \"log_path\": \"~/runs/trace-verdict-study/vota_ae_only_seed42.log\"}, \"full_trace_seed42_v5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:46:03.068Z\", \"updated_at\": \"2026-05-15T15:50:39.179Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace/final/\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_seed42_v5.log\", \"wall_clock_seconds\": 7852, \"gpu_hours\": 2.18}, \"hypothesis\": \"Full execution trace with chat-template-aware truncation provides verdict accuracy lift vs no-trace baseline (v5: fixed chat template overhead)\", \"reproduce\": {\"finished_at\": \"2026-05-15T03:58:14.030Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T03:58:14.897249+00:00\"}]}, \"metrics\": {\"accuracy\": 0.8176, \"majority_baseline\": 0.7151, \"lift\": 0.1025, \"n\": 1190, \"pass_precision\": 0.8774, \"pass_recall\": 0.866, \"pass_f1\": 0.8717, \"fail_precision\": 0.6743, \"fail_recall\": 0.6962, \"fail_f1\": 0.6851, \"accuracy_ci_lower\": 0.797, \"accuracy_ci_upper\": 0.839, \"lift_vs_notrace\": 0.0664, \"lift_vs_notrace_ci_lower\": 0.0437, \"lift_vs_notrace_ci_upper\": 0.0899, \"train_loss\": 0.05, \"eval_loss\": 0.0867, \"wall_clock_seconds\": 7852, \"epoch_level\": {\"epoch1_accuracy\": 0.8303, \"epoch2_accuracy\": 0.763, \"final_accuracy\": 0.8176, \"trend\": \"non_monotonic_epoch1_best_epoch2_collapse\"}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T04:06:20.880Z\", \"notes\": \"✅ Paired bootstrap CI (2026-05-15): lift vs no_trace = +6.6pp [4.4, 9.0]pp (significant, N=10000). lift_ci in registry [7.4, 13.2] was vs majority, not vs no_trace — now corrected.\"}, \"no_trace_seed42_v5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:46:17.948Z\", \"updated_at\": \"2026-05-15T15:50:35.449Z\", \"hypothesis\": \"Baseline: verdict accuracy without execution trace (v5: same code version as vota_v5/full_trace_v5 for fair comparison)\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python train/train_sft.py --condition no_trace --gpu 1 --seed 42 --wandb_project trace-verdict-study --wandb_run_name no_trace_seed42_v5\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/no_trace_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/no_trace/final\", \"log_path\": \"~/runs/trace-verdict-study/no_trace_seed42_v5.log\"}, \"completed_at\": \"2026-05-15T06:45:11.265Z\", \"metrics\": {\"accuracy\": 0.7513, \"accuracy_ci_lower\": 0.7277, \"accuracy_ci_upper\": 0.7748, \"majority_baseline\": 0.7151, \"lift\": 0.0361, \"lift_ci_lower\": 0.0042, \"lift_ci_upper\": 0.0706, \"n\": 1190, \"pass_precision\": 0.8776, \"pass_recall\": 0.7579, \"pass_f1\": 0.8134, \"fail_precision\": 0.5473, \"fail_recall\": 0.7345, \"fail_f1\": 0.6272, \"epoch_level\": {\"epoch1_accuracy\": 0.7429, \"epoch2_accuracy\": 0.763, \"final_accuracy\": 0.7513, \"trend\": \"non_monotonic_epoch2_best\"}}}, \"calibration_analysis_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:27:04.073Z\", \"updated_at\": \"2026-05-15T13:09:52.711Z\", \"spec\": {\"plan_id\": \"plan_007\", \"command\": \"python eval/calibration_analysis.py\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/\", \"data_count\": 1190, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42}, \"hypothesis\": \"Calibration analysis: ECE + reliability diagrams for VOTA/exception_only/full_trace/no_trace. Tests whether VOTA's compressed traces improve model calibration beyond accuracy (plan_007).\", \"conclusion\": \"success\", \"metrics\": {\"no_trace\": {\"ece\": 0.171476, \"mce\": 0.475643, \"brier_score\": 0.197152, \"accuracy\": 0.751261, \"n_samples\": 1190}, \"full_trace\": {\"ece\": 0.095817, \"mce\": 0.249061, \"brier_score\": 0.143924, \"accuracy\": 0.817647, \"n_samples\": 1190}, \"label_only\": {\"ece\": 0.110686, \"mce\": 0.417124, \"brier_score\": 0.120144, \"accuracy\": 0.862185, \"n_samples\": 1190}, \"loop_only\": {\"ece\": 0.083085, \"mce\": 0.183406, \"brier_score\": 0.118335, \"accuracy\": 0.856303, \"n_samples\": 1190}, \"ae_only\": {\"ece\": 0.000415, \"mce\": 0.000415, \"brier_score\": 0.000847, \"accuracy\": 0.99916, \"n_samples\": 1190}, \"exception_only\": {\"ece\": 0.002717, \"mce\": 0.835484, \"brier_score\": 0.001311, \"accuracy\": 0.998319, \"n_samples\": 1190}, \"vota\": {\"ece\": 0.00541, \"mce\": 0.622459, \"brier_score\": 0.005234, \"accuracy\": 0.994118, \"n_samples\": 1190}}, \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/calibration/\", \"log_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/calibration/calibration_metrics.json\", \"completed_at\": \"2026-05-15T12:36:49.992Z\"}, \"vota_exception_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:02:39.821Z\", \"updated_at\": \"2026-05-15T07:16:20.123Z\", \"hypothesis\": \"VOTA component ablation: exception_only condition — only exception summaries, no actual/expected or loop compression. Tests if [ERROR] events are the primary driver of VOTA's 99.2% accuracy (plan_003 sub-b)\", \"spec\": {\"command\": \"python train/train_sft.py --condition exception_only --gpu 1 --seed 42 --wandb_project trace-verdict-study --wandb_run_name vota_exception_only_seed42 && python eval/evaluate.py --condition exception_only --checkpoint_dir /root/autodl-tmp/trace-verdict-study-checkpoints/exception_only/final --gpu 1\", \"server\": \"westd-11235\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/exception_only_{train,test}.jsonl\", \"data_count\": {\"train\": 4720, \"test\": 1190}, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"~/runs/trace-verdict-study/vota_exception_only_seed42.log\", \"failure_reason\": \"OOM at step 8/444 — missing --gradient_checkpointing flag\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T07:16:20.123Z\"}, \"vota_seed42_v4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:12:38.660Z\", \"updated_at\": \"2026-05-15T01:37:13.355Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/vota/final/\", \"log_path\": \"~/runs/trace-verdict-study/vota_seed42_v4.log\", \"wall_clock_seconds\": 8160, \"gpu_hours\": 2.27}, \"hypothesis\": \"VOTA trace provides verdict accuracy lift over no-trace baseline (v4: removed match leakage + fixed label truncation)\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.9563, \"majority_baseline\": 0.7151, \"lift\": 0.2412, \"n\": 1190, \"pass_precision\": 0.944, \"pass_recall\": 0.998, \"pass_f1\": 0.97, \"fail_precision\": 0.993, \"fail_recall\": 0.853, \"fail_f1\": 0.917, \"lift_vs_notrace\": 0.205, \"lift_vs_notrace_ci_lower\": 0.177, \"lift_vs_notrace_ci_upper\": 0.234, \"train_loss\": 0.046, \"eval_loss\": 0.0842}, \"completed_at\": \"2026-05-15T01:10:45.307Z\"}, \"full_trace_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:12:46.333Z\", \"updated_at\": \"2026-05-15T01:10:45.707Z\", \"hypothesis\": \"Full execution trace with smart truncation (label preserved) provides verdict accuracy lift vs no-trace baseline\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace/final/\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_seed42_v2.log\", \"wall_clock_seconds\": 7860, \"gpu_hours\": 2.18}, \"metrics\": {\"accuracy\": 0.284, \"majority_baseline\": 0.7151, \"lift\": -0.4311, \"n\": 1190, \"pass_precision\": 0.923, \"pass_recall\": 0.085, \"pass_f1\": 0.155, \"fail_precision\": 0.445, \"fail_recall\": 0.785, \"fail_f1\": 0.568, \"train_loss\": 0.0373, \"eval_loss\": 0.082, \"eval_mean_token_accuracy\": 0.984}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T01:10:45.708Z\"}, \"no_trace_seed42_v4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:12:37.755Z\", \"updated_at\": \"2026-05-14T22:39:32.197Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/no_trace/final/\", \"log_path\": \"~/runs/trace-verdict-study/no_trace_seed42_v4.log\", \"wall_clock_seconds\": 1274.7, \"gpu_hours\": 0.35}, \"hypothesis\": \"Baseline: verdict accuracy without execution trace (v4: fixed label truncation)\", \"reproduce\": {\"finished_at\": \"2026-05-14T22:34:36.523Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T22:34:37.283133+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.7513, \"majority_baseline\": 0.7151, \"lift\": 0.0361, \"pass_precision\": 0.8776, \"pass_recall\": 0.7579, \"pass_f1\": 0.8134, \"fail_precision\": 0.5473, \"fail_recall\": 0.7345, \"fail_f1\": 0.6272, \"train_loss\": 0.18, \"eval_loss\": 0.6454, \"eval_mean_token_accuracy\": 0.8897}, \"completed_at\": \"2026-05-14T22:39:12.249Z\"}, \"full_trace_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:38:06.325Z\", \"updated_at\": \"2026-05-14T22:12:18.859Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/trace-verdict-study && python train/train_sft.py --condition full_trace --gpu 0 --wandb_project trace-verdict-study --wandb_run_name full_trace_seed42\\\"\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"712469\", \"log_path\": \"~/runs/trace-verdict-study/full_trace_seed42.log\", \"submitted_at\": \"2026-05-14T18:38:06.317Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/full_trace_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"hypothesis\": \"Full execution trace (line-by-line Scratchpad format) provides verdict accuracy lift vs no-trace baseline\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/full_trace/final/\", \"wall_clock_seconds\": 11247.5, \"gpu_hours\": 3.12}, \"conclusion\": \"killed\", \"metrics\": {\"train_loss\": 0.037, \"eval_loss\": 0.084, \"eval_mean_token_accuracy\": 0.984, \"accuracy\": 0.284, \"majority_baseline\": 0.7151, \"lift\": -0.431, \"pass_precision\": 0.88, \"pass_recall\": 0.08, \"pass_f1\": 0.16, \"fail_precision\": 0.31, \"fail_recall\": 0.97, \"fail_f1\": 0.57}, \"completed_at\": \"2026-05-14T21:45:33.847Z\"}, \"no_trace_seed42_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:01:02.647Z\", \"updated_at\": \"2026-05-14T22:12:18.583Z\", \"spec\": {\"command\": \"python train/train_sft.py --condition no_trace --gpu 0\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:0\"], \"pid\": \"710523\", \"log_path\": \"~/runs/trace-verdict-study/no_trace_seed42_v3.log\", \"submitted_at\": \"2026-05-14T18:01:02.641Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/no_trace_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"hypothesis\": \"Baseline: verdict accuracy without execution trace\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/no_trace/final/\", \"wall_clock_seconds\": 4617.5, \"gpu_hours\": 1.28}, \"conclusion\": \"killed\", \"metrics\": {\"train_loss\": 0.18, \"eval_loss\": 0.645, \"eval_mean_token_accuracy\": 0.89, \"accuracy\": 0.7513, \"majority_baseline\": 0.7151, \"lift\": 0.0361, \"pass_precision\": 0.8776, \"pass_recall\": 0.7579, \"pass_f1\": 0.8134, \"fail_precision\": 0.5473, \"fail_recall\": 0.7345, \"fail_f1\": 0.6272}, \"completed_at\": \"2026-05-14T19:18:00.158Z\"}, \"vota_seed42_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:01:04.345Z\", \"updated_at\": \"2026-05-14T21:51:40.917Z\", \"spec\": {\"command\": \"python train/train_sft.py --condition vota --gpu 1\", \"server\": \"westd-11235\", \"gpu\": [\"cuda:1\"], \"pid\": \"710601\", \"log_path\": \"~/runs/trace-verdict-study/vota_seed42_v3.log\", \"submitted_at\": \"2026-05-14T18:01:04.338Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/trace-verdict-study-data/vota_train.jsonl\", \"data_count\": 4720, \"model_name\": \"Qwen2.5-Coder-7B-Instruct\", \"seed\": 42, \"hypothesis\": \"VOTA trace provides significant verdict accuracy lift over no-trace baseline\", \"checkpoint_path\": \"/root/autodl-tmp/trace-verdict-study-checkpoints/vota/final/\", \"wall_clock_seconds\": 13468.8, \"gpu_hours\": 3.74}, \"conclusion\": \"killed\", \"metrics\": {\"train_loss\": 0.046, \"eval_loss\": 0.085, \"eval_mean_token_accuracy\": 0.983, \"accuracy\": 0.992, \"majority_baseline\": 0.7151, \"lift\": 0.276, \"pass_precision\": 0.99, \"pass_recall\": 0.99, \"pass_f1\": 0.99, \"fail_precision\": 0.99, \"fail_recall\": 0.99, \"fail_f1\": 0.99}, \"completed_at\": \"2026-05-14T21:45:33.135Z\"}}, \"count\": 188, \"total\": 188, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5517}}"
    }
  }
}
```

</details>

---


### Assistant

_source line 15_

<details><summary>Logged reasoning block</summary>

```text
The registry data is too large to read directly. I need to use subagents to handle this. Let me:

1. Read all .tex files from `docs/paper/` (the canonical location locally)
2. Parse the registry data using jq

Let me spawn multiple agents to handle this in parallel:
- One agent to read all .tex files and extract all quantitative claims
- One agent to parse the registry and extract all metrics needed for verification

Actually, let me think about this more carefully. The task is complex - I need to cross-reference paper claims with registry data. Let me break this into parallel subagents:

1. Agent 1: Read all .tex files and extract every quantitative claim with location


2. Agent 2: Parse registry data and extract all relevant metrics organized by experiment

Then I'll do the cross-referencing myself.

Actually, the .tex files are local and manageable, so I'll read those directly and just spawn an agent to handle the registry parsing.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "2b7916b3-64fd-48d8-b90a-5958de6a662a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012brTbzezUo9HdHSffBPKci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1489,
      "cache_read_input_tokens": 25293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1489
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

_source line 16_

论文文件在 `docs/paper/` 目录。现在并行读取所有 .tex 文件和解析 registry 数据。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "43ca6bb1-4955-4355-b0d3-7e4822bd51df",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012brTbzezUo9HdHSffBPKci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1489,
      "cache_read_input_tokens": 25293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1489
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

_source line 17_

<details open><summary>🔧 Tool call — Read · `toolu_01ExqEt9pFnEjWYBjfGfxTth`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "5a0c0e85-027a-4c4a-b430-e9500d5be542",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012brTbzezUo9HdHSffBPKci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1489,
      "cache_read_input_tokens": 25293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1489
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

_source line 18 · 2026-05-23T19:17:29.917Z_

<details><summary>↩ Tool result · `toolu_01ExqEt9pFnEjWYBjfGfxTth`</summary>

```text
1	\documentclass[11pt,a4paper]{article}
2	\usepackage[review]{acl}
3	% \usepackage{acl}  % uncomment for camera-ready (remove [review])
4	\usepackage{times,latexsym}
5	\usepackage{amsmath,amssymb}
6	\usepackage{graphicx}
7	\graphicspath{{../../figures/paper/}}
8	\usepackage{booktabs}
9	\usepackage{multirow}
10	\usepackage{xcolor}
11	\usepackage{algorithm}
12	\usepackage{algorithmic}
13	
14	\title{Complete Execution Traces Degrade SFT-Based Verdict Prediction: \\A Diagnostic Signal Analysis}
15	\author{Anonymous ACL submission}
16	
17	\begin{document}
18	\maketitle
19	
20	\begin{abstract}
21	Complete execution traces contain all information needed for verdict prediction (classifying whether a test passes or fails), yet they actively impair SFT learning.
22	Across four code-specialized models (1.5B--13B, three architecture families), complete traces achieve only 77--82\% while compact exception events reach ${\geq}$99.33\%.
23	A regex exploiting format markers matches this ceiling, but marker removal collapses it to 28.49\% while SFT retains 97.65\%; cross-dataset transfer shows SFT acquires diagnostic patterns beyond format matching.
24	Gradient masking attributes ${\leq}$4\% of the 18--23pp gap to gradient dilution; content quality at inference explains the majority, though forward-pass attention remains an unquantified residual.
25	With compact exception input, SFT on a 7B model surpasses GPT-4o by 12pp, whereas the ranking reverses without trace information---input density dominates model scale.
26	An empirical two-tier signal hierarchy holds across families, yielding a practical strategy: extract exception events first; when unavailable, tail-truncated traces (${\geq}$512 tokens) provide a viable fallback.
27	\end{abstract}
28	
29	\input{introduction}
30	\input{method}
31	\input{experiments}
32	\input{discussion}
33	\input{related_work}
34	\input{conclusion}
35	
36	\section*{Limitations}
37	
38	All experiments use Python-only benchmarks (HumanEval, MBPP-sanitized; 591 problems with simple assert-based tests); generalization to other languages, non-assert test frameworks, and multi-file projects is unverified.
39	All four models (1.5B--13B) are code-specialized; 30B+ models or general-purpose LLMs may behave differently.
40	Multi-seed experiments use 3 seeds; several baselines rely on single-seed results with Wilson CI variance estimates.
41	
42	\bibliography{references}
43	
44	\appendix
45	\input{appendix}
46	
47	\end{document}
48	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "1cdcbf34-5a41-4909-be02-6303f3d1e27d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/main.tex",
      "content": "\\documentclass[11pt,a4paper]{article}\n\\usepackage[review]{acl}\n% \\usepackage{acl}  % uncomment for camera-ready (remove [review])\n\\usepackage{times,latexsym}\n\\usepackage{amsmath,amssymb}\n\\usepackage{graphicx}\n\\graphicspath{{../../figures/paper/}}\n\\usepackage{booktabs}\n\\usepackage{multirow}\n\\usepackage{xcolor}\n\\usepackage{algorithm}\n\\usepackage{algorithmic}\n\n\\title{Complete Execution Traces Degrade SFT-Based Verdict Prediction: \\\\A Diagnostic Signal Analysis}\n\\author{Anonymous ACL submission}\n\n\\begin{document}\n\\maketitle\n\n\\begin{abstract}\nComplete execution traces contain all information needed for verdict prediction (classifying whether a test passes or fails), yet they actively impair SFT learning.\nAcross four code-specialized models (1.5B--13B, three architecture families), complete traces achieve only 77--82\\% while compact exception events reach ${\\geq}$99.33\\%.\nA regex exploiting format markers matches this ceiling, but marker removal collapses it to 28.49\\% while SFT retains 97.65\\%; cross-dataset transfer shows SFT acquires diagnostic patterns beyond format matching.\nGradient masking attributes ${\\leq}$4\\% of the 18--23pp gap to gradient dilution; content quality at inference explains the majority, though forward-pass attention remains an unquantified residual.\nWith compact exception input, SFT on a 7B model surpasses GPT-4o by 12pp, whereas the ranking reverses without trace information---input density dominates model scale.\nAn empirical two-tier signal hierarchy holds across families, yielding a practical strategy: extract exception events first; when unavailable, tail-truncated traces (${\\geq}$512 tokens) provide a viable fallback.\n\\end{abstract}\n\n\\input{introduction}\n\\input{method}\n\\input{experiments}\n\\input{discussion}\n\\input{related_work}\n\\input{conclusion}\n\n\\section*{Limitations}\n\nAll experiments use Python-only benchmarks (HumanEval, MBPP-sanitized; 591 problems with simple assert-based tests); generalization to other languages, non-assert test frameworks, and multi-file projects is unverified.\nAll four models (1.5B--13B) are code-specialized; 30B+ models or general-purpose LLMs may behave differently.\nMulti-seed experiments use 3 seeds; several baselines rely on single-seed results with Wilson CI variance estimates.\n\n\\bibliography{references}\n\n\\appendix\n\\input{appendix}\n\n\\end{document}\n",
      "numLines": 48,
      "startLine": 1,
      "totalLines": 48
    }
  }
}
```

</details>

---


### Tool call

_source line 19_

<details open><summary>🔧 Tool call — Read · `toolu_016cm2oSmnhPKCrLncexNna7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "6012c5ee-c957-4280-bc70-7aa8aa7f6ced",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012brTbzezUo9HdHSffBPKci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1489,
      "cache_read_input_tokens": 25293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1489
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

_source line 20 · 2026-05-23T19:17:30.393Z_

<details><summary>↩ Tool result · `toolu_016cm2oSmnhPKCrLncexNna7`</summary>

```text
1	\section{Introduction}
2	
3	Execution traces (line-by-line records of a program's runtime behavior) have emerged as a promising input modality for code language models \citep{chen2025tracepile,ding2024traced,wang2025dcsh,ni2024next}.
4	The intuition is straightforward: more execution information should help the model make better predictions.
5	Yet for verdict prediction (classifying whether a test passes or fails), this intuition is wrong.
6	Complete traces \emph{actively degrade} accuracy compared to compact exception events, despite containing strictly more information.
7	
8	Prior work found trace utility to be task-dependent \citep{wang2025dcsh}, but focused on generation-oriented tasks where output noise confounds the analysis.
9	Verdict prediction offers a cleaner testbed: as binary classification, it isolates the learning signal from generation noise, and controlled component ablation directly measures how trace content affects SFT learning.
10	This approach aligns with recent *ACL precedent: CRUXEval \citep{gu2024cruxeval} uses execution prediction to probe code reasoning, and NExT \citep{ni2024next} uses trace-augmented chain-of-thought for program repair.
11	
12	We present a systematic component ablation of trace representations for verdict prediction.
13	Using 591 problems from HumanEval \citep{chen2021evaluating} and MBPP-sanitized \citep{austin2021program}, we evaluate four models across three architecture families and 1.5B to 13B parameters: Qwen-2.5-Coder-7B/1.5B-Instruct \citep{qwen2024coder}, CodeLlama-13B-Instruct \citep{roziere2024code}, and DeepSeek-Coder-6.7B-Instruct \citep{deepseek2024coder}.
14	
15	The central result: complete traces (77--82\%) barely improve over source code alone, while compact exception events achieve near-perfect accuracy (${\geq}$99\%) across all four models, an 18--23pp gap (\S\ref{sec:cross_model}).
16	A simple regex exploiting a format marker matches this ceiling, so the interesting question is not why exceptions help but \emph{why complete traces hurt}.
17	Marker removal collapses the regex to near-chance while SFT retains $>$97\%; cross-dataset transfer confirms SFT acquires diagnostic patterns beyond format matching (\S\ref{sec:nomarker}).
18	
19	Gradient masking attributes ${\leq}$4\% of the degradation to gradient dilution; content quality at inference accounts for the majority (\S\ref{sec:density}).
20	Training dynamics corroborate this: \texttt{exception\_only} converges within 50 steps while \texttt{full\_trace} oscillates without convergence (Appendix~\ref{sec:training_dynamics}).
21	A tail-truncation budget sweep reveals a sharp performance transition near 512 tokens, coinciding with the first appearance of structured execution markers (\S\ref{sec:trace_length}).
22	
23	While exception events structurally encode verdict direction (exception present typically implies failure), the non-trivial finding is that providing strictly more information (complete traces containing all exception data) degrades performance by 18--23pp.
24	Our contributions:
25	\begin{enumerate}
26	\item \textbf{Complete traces degrade SFT verdict accuracy} despite containing all diagnostic information: across four models (1.5B--13B, three families), complete traces (77--82\%) remain near source-code-only levels while compact exception events close an 18--23pp gap to ${\geq}$99.33\% (\S\ref{sec:cross_model}).
27	
28	\item \textbf{Semantic vs.\ format-marker decomposition}: marker removal collapses a format-exploiting regex by 71pp while SFT drops only 2pp; cross-dataset transfer (99.4--100\%) shows the learned signal generalizes beyond format markers (\S\ref{sec:nomarker}).
29	
30	\item \textbf{A two-tier signal hierarchy}: exception/assertion signals (${\geq}$98.53\%) dominate loop compression (77--86\%) by 12+pp with non-overlapping CIs; a sharp transition at ${\sim}$512 tail tokens yields a practical fallback (\S\ref{sec:ablation}, \S\ref{sec:trace_length}).
31	
32	\item \textbf{Mechanistic decomposition}: controlled gradient masking attributes ${\leq}$4\% of the degradation to gradient dilution, assigning the majority to content quality at inference, though forward-pass attention is an unquantified residual (\S\ref{sec:density}).
33	\end{enumerate}
34	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "6bafd380-a22e-4a9f-a556-08e01ad46ce0",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\nExecution traces (line-by-line records of a program's runtime behavior) have emerged as a promising input modality for code language models \\citep{chen2025tracepile,ding2024traced,wang2025dcsh,ni2024next}.\nThe intuition is straightforward: more execution information should help the model make better predictions.\nYet for verdict prediction (classifying whether a test passes or fails), this intuition is wrong.\nComplete traces \\emph{actively degrade} accuracy compared to compact exception events, despite containing strictly more information.\n\nPrior work found trace utility to be task-dependent \\citep{wang2025dcsh}, but focused on generation-oriented tasks where output noise confounds the analysis.\nVerdict prediction offers a cleaner testbed: as binary classification, it isolates the learning signal from generation noise, and controlled component ablation directly measures how trace content affects SFT learning.\nThis approach aligns with recent *ACL precedent: CRUXEval \\citep{gu2024cruxeval} uses execution prediction to probe code reasoning, and NExT \\citep{ni2024next} uses trace-augmented chain-of-thought for program repair.\n\nWe present a systematic component ablation of trace representations for verdict prediction.\nUsing 591 problems from HumanEval \\citep{chen2021evaluating} and MBPP-sanitized \\citep{austin2021program}, we evaluate four models across three architecture families and 1.5B to 13B parameters: Qwen-2.5-Coder-7B/1.5B-Instruct \\citep{qwen2024coder}, CodeLlama-13B-Instruct \\citep{roziere2024code}, and DeepSeek-Coder-6.7B-Instruct \\citep{deepseek2024coder}.\n\nThe central result: complete traces (77--82\\%) barely improve over source code alone, while compact exception events achieve near-perfect accuracy (${\\geq}$99\\%) across all four models, an 18--23pp gap (\\S\\ref{sec:cross_model}).\nA simple regex exploiting a format marker matches this ceiling, so the interesting question is not why exceptions help but \\emph{why complete traces hurt}.\nMarker removal collapses the regex to near-chance while SFT retains $>$97\\%; cross-dataset transfer confirms SFT acquires diagnostic patterns beyond format matching (\\S\\ref{sec:nomarker}).\n\nGradient masking attributes ${\\leq}$4\\% of the degradation to gradient dilution; content quality at inference accounts for the majority (\\S\\ref{sec:density}).\nTraining dynamics corroborate this: \\texttt{exception\\_only} converges within 50 steps while \\texttt{full\\_trace} oscillates without convergence (Appendix~\\ref{sec:training_dynamics}).\nA tail-truncation budget sweep reveals a sharp performance transition near 512 tokens, coinciding with the first appearance of structured execution markers (\\S\\ref{sec:trace_length}).\n\nWhile exception events structurally encode verdict direction (exception present typically implies failure), the non-trivial finding is that providing strictly more information (complete traces containing all exception data) degrades performance by 18--23pp.\nOur contributions:\n\\begin{enumerate}\n\\item \\textbf{Complete traces degrade SFT verdict accuracy} despite containing all diagnostic information: across four models (1.5B--13B, three families), complete traces (77--82\\%) remain near source-code-only levels while compact exception events close an 18--23pp gap to ${\\geq}$99.33\\% (\\S\\ref{sec:cross_model}).\n\n\\item \\textbf{Semantic vs.\\ format-marker decomposition}: marker removal collapses a format-exploiting regex by 71pp while SFT drops only 2pp; cross-dataset transfer (99.4--100\\%) shows the learned signal generalizes beyond format markers (\\S\\ref{sec:nomarker}).\n\n\\item \\textbf{A two-tier signal hierarchy}: exception/assertion signals (${\\geq}$98.53\\%) dominate loop compression (77--86\\%) by 12+pp with non-overlapping CIs; a sharp transition at ${\\sim}$512 tail tokens yields a practical fallback (\\S\\ref{sec:ablation}, \\S\\ref{sec:trace_length}).\n\n\\item \\textbf{Mechanistic decomposition}: controlled gradient masking attributes ${\\leq}$4\\% of the degradation to gradient dilution, assigning the majority to content quality at inference, though forward-pass attention is an unquantified residual (\\S\\ref{sec:density}).\n\\end{enumerate}\n",
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

_source line 21_

<details open><summary>🔧 Tool call — Read · `toolu_01QnsDzwBY5jbpCeVtdANfzi`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "13e876ec-cb68-49fa-90fe-f5ff7c54ab93",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012brTbzezUo9HdHSffBPKci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1489,
      "cache_read_input_tokens": 25293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1489
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

_source line 22 · 2026-05-23T19:17:30.909Z_

<details><summary>↩ Tool result · `toolu_01QnsDzwBY5jbpCeVtdANfzi`</summary>

```text
1	\section{Method}
2	
3	\subsection{Task Definition and Diagnostic Signal Metrics}
4	
5	We study \emph{verdict prediction}: given a Python function, a test input, and an optional execution trace, predict whether the test passes or fails.
6	The model produces a single token (\texttt{pass} or \texttt{fail}), making this a binary classification task.
7	Unlike code generation \citep{chen2025tracepile} or output prediction \citep{gu2024cruxeval}, verdict prediction isolates the model's ability to detect faults from its ability to simulate execution, providing cleaner ablation contrasts than generation tasks.
8	
9	To quantify signal quality without circular reference to model accuracy, we define the \emph{diagnostic token ratio} $d = n_{\text{diag}} / n_{\text{total}}$, where $n_{\text{diag}}$ counts tokens matching exception or assertion patterns.
10	This model-free metric correlates with accuracy at Pearson $r{=}0.949$ ($p{=}0.014$, $N{=}5$, df=3; treat as descriptive), but captures only the \emph{explicit} diagnostic pathway; tail-truncated conditions achieve 93--98\% with $d {\approx} 0$, indicating a second, implicit signal channel operating through terminal execution state (\S\ref{sec:density}).
11	
12	\subsection{Dataset}
13	\label{sec:dataset}
14	
15	We sampled 10 candidate solutions per problem from Qwen-2.5-Coder-7B-Instruct (temperature 0.8, top\_p 0.95) for 591 problems from HumanEval \citep{chen2021evaluating} (164) and MBPP-sanitized \citep{austin2021program} (427), executed each against canonical tests with \texttt{sys.settrace} to obtain line-level traces and pass/fail verdicts, yielding 5,910 pairs (67\% pass, 33\% fail).
16	The dataset is split 80/20 by problem ID into 4,720 training and 1,190 test samples (majority baseline: 71.51\%).
17	The \texttt{exception\_only} format collapses passing solutions into identical rows (39.45\% train, 48.99\% test duplicates); these duplicates arise from multiple candidate solutions per problem, with the train--test split enforced at the problem level (472 train / 119 test problems, zero crossover; Appendix~\ref{sec:dedup_stats}).
18	
19	\subsection{Trace Representations}
20	
21	We define seven conditions that vary the trace information available (Figure~\ref{fig:trace_overview}):
22	\begin{itemize}
23	\item \texttt{no\_trace}: Source code and test input only.
24	\item \texttt{full\_trace}: Complete line-by-line trace with variable states.
25	\item \texttt{VOTA} (Verdict-Optimized Trace Abstraction): Exception events + assertion-point comparisons + loop compression (Appendix~\ref{sec:vota_algorithm}).
26	\item \texttt{exception\_only}: Only exception/error events.
27	\item \texttt{ae\_only}: Only assertion-point actual/expected pairs.
28	\item \texttt{loop\_only}: Only loop compression summaries.
29	\item \texttt{VOTA\_no\_ae}: VOTA without assertion-point information.
30	\end{itemize}
31	
32	\begin{figure*}[t]
33	\centering
34	\includegraphics[width=\textwidth]{fig1_trace_overview}
35	\caption{Overview of the verdict prediction pipeline. Source code and a test input are executed to produce a full raw trace. Four conditions vary the trace information: \texttt{no\_trace} (75.13\%), \texttt{full\_trace} (81.44\%), VOTA (99.05\%), and \texttt{exception\_only} (99.83\%). Accuracies for Qwen-2.5-7B ($N{=}1{,}190$); multi-seed means where available (Table~\ref{tab:ablation}). Appendix~\ref{sec:vota_examples} provides input/output examples.}
36	\label{fig:trace_overview}
37	\end{figure*}
38	
39	\subsection{Models and Training}
40	
41	We evaluate four models spanning three architecture families: \textbf{Qwen-2.5-Coder-7B/1.5B-Instruct} \citep{qwen2024coder}, \textbf{CodeLlama-13B-Instruct} \citep{roziere2024code}, and \textbf{DeepSeek-Coder-6.7B-Instruct} \citep{deepseek2024coder}, covering a 1.5B--13B parameter range (8.7$\times$).
42	All conditions use LoRA \citep{hu2022lora} (rank=16, $\alpha$=32, dropout=0.05) on all linear layers, 3 epochs, effective batch size 32, LR $2 \times 10^{-4}$ with linear warmup/decay, max sequence length 2{,}048 tokens.
43	Sequences exceeding this limit are truncated while preserving the verdict label.
44	The primary seed is 42; seeds 123 and 456 test \texttt{exception\_only} robustness (Appendix~\ref{sec:training_details}).
45	
46	\subsection{Loss Ablation}
47	
48	To probe the contribution of gradient dilution, we introduce \texttt{full\_trace\_label\_only}: identical full-trace input but loss computed only on the verdict token (trace positions masked).
49	TRL's SFTTrainer computes mean cross-entropy over label tokens, so label-only loss does not amplify the effective learning rate.
50	However, this ablation simultaneously changes three variables: (1)~which tokens receive gradient updates, (2)~the implicit regularization from predicting trace tokens, and (3)~the training signal distribution.
51	The resulting improvement over standard \texttt{full\_trace} provides a confounded upper bound on gradient dilution's contribution.
52	A cleaner test (masking 99.8\% of gradient updates during \texttt{exception\_only} training) matches the diagnostic token ratio of full traces while preserving compact input, isolating gradient dilution from content quality (\S\ref{sec:density}).
53	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "7acc7fb7-cf82-45d8-92e1-6090ccb1d302",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/method.tex",
      "content": "\\section{Method}\n\n\\subsection{Task Definition and Diagnostic Signal Metrics}\n\nWe study \\emph{verdict prediction}: given a Python function, a test input, and an optional execution trace, predict whether the test passes or fails.\nThe model produces a single token (\\texttt{pass} or \\texttt{fail}), making this a binary classification task.\nUnlike code generation \\citep{chen2025tracepile} or output prediction \\citep{gu2024cruxeval}, verdict prediction isolates the model's ability to detect faults from its ability to simulate execution, providing cleaner ablation contrasts than generation tasks.\n\nTo quantify signal quality without circular reference to model accuracy, we define the \\emph{diagnostic token ratio} $d = n_{\\text{diag}} / n_{\\text{total}}$, where $n_{\\text{diag}}$ counts tokens matching exception or assertion patterns.\nThis model-free metric correlates with accuracy at Pearson $r{=}0.949$ ($p{=}0.014$, $N{=}5$, df=3; treat as descriptive), but captures only the \\emph{explicit} diagnostic pathway; tail-truncated conditions achieve 93--98\\% with $d {\\approx} 0$, indicating a second, implicit signal channel operating through terminal execution state (\\S\\ref{sec:density}).\n\n\\subsection{Dataset}\n\\label{sec:dataset}\n\nWe sampled 10 candidate solutions per problem from Qwen-2.5-Coder-7B-Instruct (temperature 0.8, top\\_p 0.95) for 591 problems from HumanEval \\citep{chen2021evaluating} (164) and MBPP-sanitized \\citep{austin2021program} (427), executed each against canonical tests with \\texttt{sys.settrace} to obtain line-level traces and pass/fail verdicts, yielding 5,910 pairs (67\\% pass, 33\\% fail).\nThe dataset is split 80/20 by problem ID into 4,720 training and 1,190 test samples (majority baseline: 71.51\\%).\nThe \\texttt{exception\\_only} format collapses passing solutions into identical rows (39.45\\% train, 48.99\\% test duplicates); these duplicates arise from multiple candidate solutions per problem, with the train--test split enforced at the problem level (472 train / 119 test problems, zero crossover; Appendix~\\ref{sec:dedup_stats}).\n\n\\subsection{Trace Representations}\n\nWe define seven conditions that vary the trace information available (Figure~\\ref{fig:trace_overview}):\n\\begin{itemize}\n\\item \\texttt{no\\_trace}: Source code and test input only.\n\\item \\texttt{full\\_trace}: Complete line-by-line trace with variable states.\n\\item \\texttt{VOTA} (Verdict-Optimized Trace Abstraction): Exception events + assertion-point comparisons + loop compression (Appendix~\\ref{sec:vota_algorithm}).\n\\item \\texttt{exception\\_only}: Only exception/error events.\n\\item \\texttt{ae\\_only}: Only assertion-point actual/expected pairs.\n\\item \\texttt{loop\\_only}: Only loop compression summaries.\n\\item \\texttt{VOTA\\_no\\_ae}: VOTA without assertion-point information.\n\\end{itemize}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig1_trace_overview}\n\\caption{Overview of the verdict prediction pipeline. Source code and a test input are executed to produce a full raw trace. Four conditions vary the trace information: \\texttt{no\\_trace} (75.13\\%), \\texttt{full\\_trace} (81.44\\%), VOTA (99.05\\%), and \\texttt{exception\\_only} (99.83\\%). Accuracies for Qwen-2.5-7B ($N{=}1{,}190$); multi-seed means where available (Table~\\ref{tab:ablation}). Appendix~\\ref{sec:vota_examples} provides input/output examples.}\n\\label{fig:trace_overview}\n\\end{figure*}\n\n\\subsection{Models and Training}\n\nWe evaluate four models spanning three architecture families: \\textbf{Qwen-2.5-Coder-7B/1.5B-Instruct} \\citep{qwen2024coder}, \\textbf{CodeLlama-13B-Instruct} \\citep{roziere2024code}, and \\textbf{DeepSeek-Coder-6.7B-Instruct} \\citep{deepseek2024coder}, covering a 1.5B--13B parameter range (8.7$\\times$).\nAll conditions use LoRA \\citep{hu2022lora} (rank=16, $\\alpha$=32, dropout=0.05) on all linear layers, 3 epochs, effective batch size 32, LR $2 \\times 10^{-4}$ with linear warmup/decay, max sequence length 2{,}048 tokens.\nSequences exceeding this limit are truncated while preserving the verdict label.\nThe primary seed is 42; seeds 123 and 456 test \\texttt{exception\\_only} robustness (Appendix~\\ref{sec:training_details}).\n\n\\subsection{Loss Ablation}\n\nTo probe the contribution of gradient dilution, we introduce \\texttt{full\\_trace\\_label\\_only}: identical full-trace input but loss computed only on the verdict token (trace positions masked).\nTRL's SFTTrainer computes mean cross-entropy over label tokens, so label-only loss does not amplify the effective learning rate.\nHowever, this ablation simultaneously changes three variables: (1)~which tokens receive gradient updates, (2)~the implicit regularization from predicting trace tokens, and (3)~the training signal distribution.\nThe resulting improvement over standard \\texttt{full\\_trace} provides a confounded upper bound on gradient dilution's contribution.\nA cleaner test (masking 99.8\\% of gradient updates during \\texttt{exception\\_only} training) matches the diagnostic token ratio of full traces while preserving compact input, isolating gradient dilution from content quality (\\S\\ref{sec:density}).\n",
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

_source line 23_

<details open><summary>🔧 Tool call — Read · `toolu_01YQrnyBZN7iaRqav6fNZ5dF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "3f62aec4-1dce-4f8d-8419-d083cd6007b5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012brTbzezUo9HdHSffBPKci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1489,
      "cache_read_input_tokens": 25293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1489
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

_source line 24 · 2026-05-23T19:17:31.359Z_

<details><summary>↩ Tool result · `toolu_01YQrnyBZN7iaRqav6fNZ5dF`</summary>

```text
1	\section{Experiments}
2	
3	We evaluate across two research questions:
4	(1)~Why do complete traces degrade SFT verdict accuracy despite containing all diagnostic information?
5	(2)~Which trace components carry the verdict signal, and how does their density affect learning?
6	All experiments use $N{=}1{,}190$ test samples; accuracy is reported with Wilson 95\% CIs.\footnote{Problem-level partition (472 train / 119 test, zero crossover; \S\ref{sec:dataset}). \texttt{exception\_only} duplicates (48.99\% test; Appendix~\ref{sec:dedup_stats}) arise from within-problem variants; deduplication yields negligible ($<$0.1pp) delta.}
7	Pairwise comparisons use paired bootstrap resampling ($B{=}10{,}000$, seed=42); all differences are significant at $p{<}.0001$ unless noted.
8	Under problem-level clustered bootstrap ($n_\text{eff}{=}119$), all cross-tier gaps remain significant ($p{<}.001$); 3 of 80 within-tier pairwise comparisons lose significance after Holm--Bonferroni correction.
9	
10	\subsection{Cross-Model Comparison}
11	\label{sec:cross_model}
12	
13	Table~\ref{tab:cross_model} compares four models spanning an 8.7$\times$ parameter range (1.5B--13B) and three architecture families under key conditions; single-seed entries are marked with $^\dag$.
14	Regex B5 (99.33\%) exploits the \texttt{[No exception data in trace]} format marker, providing a non-learned baseline; its collapse to 28.49\% under marker removal (\S\ref{sec:nomarker}) shows the SFT advantage is not format-driven.
15	
16	\begin{table}[t]
17	\centering
18	\caption{Cross-model verdict accuracy (\%, $N{=}1{,}190$) across four models (1.5B--13B) and three architecture families. Multi-seed entries report mean$\pm$std over 2--3 seeds; $^\dag$ = single seed (seed 42). Bold: best per model. Full per-seed breakdowns in Appendix~\ref{sec:full_results}; per-class metrics in Appendix~\ref{sec:per_class}.}
19	\label{tab:cross_model}
20	\small
21	\resizebox{\columnwidth}{!}{%
22	\begin{tabular}{lcccc}
23	\toprule
24	\textbf{Condition} & \textbf{Qwen-7B} & \textbf{Qwen-1.5B} & \textbf{CL-13B} & \textbf{DS-6.7B} \\
25	\midrule
26	exception\_only & \textbf{99.83}{\scriptsize$\pm$0.00} & \textbf{99.83}{\scriptsize$\pm$0.00} & \textbf{99.89}{\scriptsize$\pm$0.10} & \textbf{99.39}{\scriptsize$\pm$0.10} \\
27	ae\_only & 99.64{\scriptsize$\pm$0.49} & 98.83{\scriptsize$\pm$0.36} & 99.08{\scriptsize$\pm$0.00} & 98.53{\scriptsize$\pm$0.30} \\
28	VOTA & 99.05{\scriptsize$\pm$0.38} & 99.54{\scriptsize$\pm$0.06} & 98.74{\scriptsize$\pm$0.24} & 99.25$^\ddag$ \\
29	loop\_only & 86.05{\scriptsize$\pm$0.52} & 79.54{\scriptsize$\pm$1.42} & 77.40{\scriptsize$\pm$1.54} & 80.31{\scriptsize$\pm$1.65} \\
30	full\_trace & 81.44{\scriptsize$\pm$1.11} & 77.06$^\dag$ & 79.9$^\S$ & 79.16$^\dag$ \\
31	no\_trace & 75.13$^\dag$ & 72.35{\scriptsize$\pm$4.48} & 76.47$^\dag$ & 73.36$^\dag$ \\
32	\midrule
33	Regex B5 (marker) & \multicolumn{4}{c}{99.33} \\
34	Majority baseline & \multicolumn{4}{c}{71.51} \\
35	\bottomrule
36	\end{tabular}%
37	}
38	\vspace{2pt}
39	\par\raggedright\footnotesize
40	$^\ddag$DeepSeek VOTA seed 42 (84.45\%) is a tokenizer-driven truncation failure (Appendix~\ref{sec:tokenizer_analysis}), reported as 2-seed mean.
41	$^\S$CodeLlama \texttt{full\_trace} not available; head-2048 proxy reported.
42	Per-seed breakdowns for all conditions in Appendix~\ref{sec:full_results}.
43	\end{table}
44	
45	\paragraph{Exception dominance across families.}
46	Under \texttt{exception\_only}, all four models achieve ${\geq}$99.33\% across all available seeds (Table~\ref{tab:cross_model}), spanning only 0.50pp across architectures (the tightest of any condition).
47	CodeLlama-13B seed 123 achieves 100\%, indicating the 2 persistent errors (\texttt{GeneratorExit}; Appendix~\ref{sec:irreducible}) are convergence artifacts; 99.83\% is a floor, not a ceiling.
48	
49	\paragraph{Scale effects concentrate in Tier~2.}
50	Tier~1 signals are scale-invariant across 1.5B--13B (8.7$\times$): both \texttt{exception\_only} and \texttt{ae\_only} span ${\leq}$1.2pp.
51	\texttt{loop\_only} spans 8.57pp, with CodeLlama-13B below Qwen-1.5B, suggesting architecture matters more than parameter count for lower-density signals.
52	In contrast, \texttt{no\_trace} scales with capacity (Figure~\ref{fig:cross_scale}) and shows the highest seed variance ($\sigma{=}$4.48pp).
53	
54	\begin{figure}[t]
55	\centering
56	\includegraphics[width=\columnwidth]{fig3_cross_model_gap}
57	\caption{Verdict accuracy vs.\ model scale. \texttt{exception\_only} maintains ${\geq}$99.33\% regardless of scale, while \texttt{no\_trace} shows monotonic sensitivity (+4.12pp). \texttt{nomarker} (markers removed) shows no scale degradation.}
58	\label{fig:cross_scale}
59	\end{figure}
60	
61	\paragraph{VOTA cross-family variation.}
62	Excluding outlier seeds, VOTA achieves ${\geq}$98.57\% across all four models (0.80pp range).
63	DeepSeek seed 42 (84.45\%) is a tokenizer-driven truncation failure (91.7\% of samples exceed 2{,}048 tokens after tokenization; Appendix~\ref{sec:tokenizer_analysis}), demonstrating that VOTA's longer sequences are sensitive to tokenizer efficiency: 1/4 models suffers catastrophic truncation under standard training length. \texttt{exception\_only}'s compact inputs (median 150 tokens) sidestep this vulnerability entirely.
64	
65	\subsection{Component Ablation}
66	\label{sec:ablation}
67	
68	Multi-seed \texttt{ae\_only} ablations use Qwen-7B; \texttt{loop\_only} is evaluated across three models to test Tier~2 generalization (Table~\ref{tab:cross_model}).
69	Table~\ref{tab:ablation} decomposes VOTA on Qwen-2.5-7B and reveals a two-tier hierarchy validated across all four models and three architecture families (Table~\ref{tab:cross_model}): Tier~1 (${\geq}$98.53\%) and Tier~2 (77--86\%) are separated by 12+pp with non-overlapping CIs.
70	
71	\begin{table}[t]
72	\centering
73	\caption{Component ablation on Qwen-2.5-7B ($N{=}1{,}190$). Tier~1 signals achieve near-perfect accuracy; combining them (VOTA) slightly dilutes performance. Entries marked $^\dag$/$^\S$/$^\ddag$ are 3-seed mean$\pm$std; unmarked entries are single seed (seed 42). Per-seed breakdowns in Appendix~\ref{sec:full_results}. Seed $\sigma$ negatively correlates with density (0.00 for exception to 0.52 for loop).}
74	\label{tab:ablation}
75	\small
76	\resizebox{\columnwidth}{!}{%
77	\begin{tabular}{llccc}
78	\toprule
79	\textbf{Condition} & \textbf{Components} & \textbf{Acc (\%)} & \textbf{95\% CI} & \textbf{Tier} \\
80	\midrule
81	ae\_only & assertion-point & 99.64$^\dag$ & [99.26, 99.87] & 1 \\
82	exception\_only & exception events & \textbf{99.83} & [99.58, 100.00] & 1 \\
83	VOTA & exc+ae+loop & 99.05$^\S$ & [98.49, 99.50] & --- \\
84	VOTA\_no\_ae & exc+loop & 99.41 & [98.90, 99.80] & --- \\
85	loop\_only & loop compression & 86.05$^\ddag$ & [83.97, 87.96] & 2 \\
86	full\_trace & complete trace & 81.44{\scriptsize$\pm$1.11} & --- & --- \\
87	no\_trace & none & 75.13 & [72.77, 77.48] & --- \\
88	\midrule
89	Regex (best) & exc.\ type regex & 93.61 & --- & --- \\
90	3-shot (Qwen-7B) & in-context learning & 90.84 & --- & --- \\
91	Zero-shot (4 models) & prompting & 51.0--93.5 & --- & --- \\
92	\bottomrule
93	\end{tabular}%
94	}
95	\end{table}
96	
97	Tier~1 signals are individually sufficient: \texttt{exception\_only} (99.83\%$\pm$0.00) exceeds VOTA (99.05\%$\pm$0.38) by +0.78pp (2/3 seeds $p{<}.05$, all directionally consistent), implying that combining signals introduces noise.
98	Removing assertion points has no effect (\texttt{VOTA\_no\_ae} = 99.41\%, single seed), indicating exception dominance.
99	Individual exception subcomponents (type, stacktrace, message) each independently achieve ${\geq}$99.50\%, indicating that the binary presence of an exception event, rather than any specific subcomponent, drives Tier~1 performance (Appendix~\ref{sec:exc_subcomponent}).
100	The Tier~1/2 boundary is unambiguous: the lowest Tier~1 condition (\texttt{ae\_only} on DeepSeek, 98.53\%$\pm$0.30, 2 seeds) exceeds the highest Tier~2 (\texttt{loop\_only} on Qwen-7B, 86.05\%, CI [83.97, 87.96]) by 12.48\,pp with non-overlapping CIs (gap statistic supports $k{=}2$ clusters, silhouette ${\geq}$0.74).
101	Tier~2 \texttt{loop\_only} lifts over \texttt{no\_trace} are model-dependent: Qwen +10.92pp (7B) and +7.19pp (1.5B); DeepSeek +6.95pp; CodeLlama +0.93pp (n.s.).
102	\paragraph{Rule-based baseline comparison.}
103	The strongest non-trivial regex heuristic (B4: exception class name matching; Table~\ref{tab:regex}) achieves 93.61\% accuracy (F1=0.876), trailing SFT \texttt{exception\_only} (99.83\%, F1=0.997) by 6.22pp (McNemar $p{<}.001$).
104	The gap concentrates on caught-exception boundary cases: regex flags all exception events as failures, while SFT learns to distinguish caught exceptions (benign, inside \texttt{try/except}) from uncaught faults, correctly resolving 6/8 boundary samples (Appendix~\ref{sec:regex_baselines}).
105	Across all formats, SFT outperforms the best applicable regex by +3.62--23.86pp (Appendix~\ref{sec:regex_baselines}).
106	
107	\paragraph{Zero-shot and few-shot LLM baselines.}
108	Zero-shot prompting spans 51.0--93.5\% across four models (42.44pp range); three-shot ICL on Qwen-7B (90.84\%) improves only 1.76pp.
109	SFT compresses this range to 0.50pp (99.39--99.89\%), closing a 6--49pp gap with 4,720 samples (Appendix~\ref{sec:zeroshot_cross_model}).
110	\paragraph{Frontier model crossover.}
111	Two frontier models illustrate that SFT's advantage depends on input density: under \texttt{no\_trace}, GPT-4o (84.45\%) and GPT-4.1 (77.31\%) outperform SFT Qwen-7B (75.13\%), but under \texttt{exception\_only} the ranking reverses (SFT 99.83\% vs.\ GPT-4o 87.98\%).
112	Compact diagnostic input unlocks SFT's full advantage over general reasoning capacity.
113	
114	\subsection{Format Marker Ablation}
115	\label{sec:nomarker}
116	
117	The \texttt{exception\_only} format includes a \texttt{[No exception data in trace]} marker in all pass-class samples (regex baseline B5 exploits this for 99.33\% accuracy; Appendix~\ref{sec:regex_baselines}).
118	To quantify the marker's contribution, we retrain with all format markers removed (\texttt{nomarker} condition).
119	
120	Qwen-7B 3-seed mean: 97.65\% $\pm$ 0.96 (seeds 42/123/456: 96.55/98.32/98.07\%), a drop of 2.18pp from \texttt{exception\_only} (99.83\%).
121	Qwen-1.5B: 97.82\%, drop of 2.01pp.
122	The marker contribution (${\sim}$2pp) accounts for only ${\sim}$9\% of the total exception lift over \texttt{no\_trace} (24.70pp on 7B).
123	Regex baselines illustrate this decomposition: B5 (\texttt{[No exception data]}$\to$pass, 99.33\% with markers) collapses to 28.49\% without markers, showing it is entirely format-dependent.
124	The strongest semantic regex B4 (exception class matching, 93.61\%) is marker-invariant; SFT \texttt{nomarker} (97.65\%) exceeds it by 4.04pp, isolating the learned semantic contribution beyond pattern matching.
125	
126	\paragraph{Cross-dataset transfer.}
127	Bidirectional evaluation demonstrates generalization: HumanEval${\to}$MBPP \texttt{exception\_only} achieves 99.41\% ($N{=}4{,}270$) and MBPP${\to}$HumanEval achieves 100.0\% ($N{=}1{,}640$), while \texttt{no\_trace} drops to near-majority baseline in both directions (70.56\% vs.\ 69.02\% majority; 67.99\% vs.\ 61.65\%).
128	The near-zero transfer loss for exception signals, across independently authored problem sets with no problem overlap, shows SFT learns language-level diagnostic patterns, not dataset-specific artifacts.
129	Under marker removal, cross-dataset accuracy drops to 95.5\% ($-$3.9pp), indicating that the majority of cross-dataset transfer relies on learned diagnostic patterns rather than format markers.
130	
131	\subsection{Decomposing the Full-Trace Degradation}
132	\label{sec:density}
133	
134	The 18.07pp gap between \texttt{exception\_only} (99.83\%) and \texttt{full\_trace} (81.76\%) could reflect gradient dilution (diagnostic tokens are ${\sim}$1/500 of full traces, diluting gradient signal during training) or content quality (verbose input buries diagnostic signals at inference).
135	
136	\paragraph{Controlled gradient masking.}
137	To isolate gradient dilution, we mask 99.8\% of gradient updates during \texttt{exception\_only} training, matching the diagnostic token ratio of full traces while preserving compact input.
138	This yields 99.22\% (mean $-$0.61pp from \texttt{exception\_only}, 3 seeds), limiting gradient dilution to ${\leq}$4\% of the 18.07pp gap (Table~\ref{tab:density}).
139	The gradient masking bound attributes the remaining ${\geq}$96\% to content quality (diagnostic signal density at inference), though forward-pass attention during masked training is an unquantified residual.
140	Note that masking affects only the backward pass; the model still attends to all input tokens during the forward pass, so this bounds gradient dilution's contribution but does not rule out attention-based information flow as a residual confound.
141	
142	\begin{table}[t]
143	\centering
144	\caption{Decomposition of the full-trace degradation (Qwen-7B). Gradient masking attributes ${\leq}$4\% to gradient dilution; the bound assigns the remainder to content quality, though forward-pass attention is a residual confound (\S\ref{sec:density}). Label-only loss provides a confounded but directionally consistent complementary estimate.}
145	\label{tab:density}
146	\small
147	\begin{tabular}{lcc}
148	\toprule
149	\textbf{Condition} & \textbf{Acc (\%)} & \textbf{$\Delta$} \\
150	\midrule
151	exception\_only & 99.83{\scriptsize$\pm$0.00} & --- \\
152	\quad + grad mask (99.8\%) & 99.22{\scriptsize$\pm$0.20}$^\S$ & $-$0.61pp \\
153	full\_trace & 81.76$^\ddag$ & $-$18.07pp \\
154	\midrule
155	\multicolumn{3}{l}{\textit{Complementary (confounded):}} \\
156	full\_trace + label-only loss & 85.94{\scriptsize$\pm$1.12} & +4.50pp$^\dag$ \\
157	\bottomrule
158	\end{tabular}
159	\vspace{2pt}
160	\par\raggedright\footnotesize
161	$^\S$Mean $\pm$ std over 3 seeds (42, 123, 456).
162	$^\ddag$Matched-seed baseline; 3-seed mean 81.44\%$\pm$1.11 (Table~\ref{tab:cross_model}).
163	$^\dag$vs.\ \texttt{full\_trace} (81.44\%$\pm$1.11); not significant under clustered bootstrap (95\% CI [$-$0.6, +9.8]pp, $n_\text{eff}{=}119$).
164	\end{table}
165	
166	\paragraph{Complementary evidence.}
167	Label-only loss on full traces (+4.50pp, 3 seeds) yields a confounded upper bound of ${\leq}$26\% gradient contribution, consistent with the masking estimate (${\leq}$4\%) but not significant under clustered bootstrap (95\% CI [$-$0.6, +9.8]pp).
168	Qwen-1.5B shows a similar label-only pattern (17\%/83\%, 3 seeds); CodeLlama and DeepSeek exhibit label-only collapse to majority baseline (28.5\%), limiting this complementary analysis to the Qwen family.
169	The architecture dependence suggests label-only training is sensitive to model capacity or optimization landscape; the gradient masking ablation provides a more robust, architecture-independent decomposition.
170	Cross-architecture validation on two additional families is directionally consistent (single seed each): DeepSeek-Coder-6.7B achieves 99.33\% and CodeLlama-13B achieves 100\% under 99.8\% masking, both well above the full-trace range (77--82\%, Table~\ref{tab:cross_model}), supporting content quality as the dominant factor across architectures.
171	Error analysis supports the content quality interpretation: all 217 \texttt{full\_trace} errors occur where tokenizer truncation removes diagnostic markers, manifesting through mechanical truncation rather than semantic confusion.
172	
173	\subsection{Complementary Analyses}
174	\label{sec:additional}
175	
176	\paragraph{Trace length ablation.}
177	\label{sec:trace_length}
178	Varying the head-truncated trace token budget (256--no limit) on Qwen-7B yields accuracy in a narrow 77.2\%--81.8\% band with a non-monotonic pattern: 1024-token prefixes (77.23\%) underperform 512-token prefixes (80.42\%, $p{=}.002$), because mid-length prefixes retain enough irrelevant content to mislead the model while discarding diagnostic events near the trace terminus (Appendix~\ref{sec:trace_length_full}).
179	Critically, removing the token budget entirely (no truncation) yields 81.76\%, identical to head-2048, ruling out truncation as the explanation for the full-trace degradation.
180	This non-monotonicity is specific to head-truncation; under tail-truncation, accuracy increases monotonically for two of three models (Table~\ref{tab:tail_cross_model} in Appendix), with only DeepSeek showing a mild architecture-specific reversal at tail-1024$\to$tail-2048 ($-$1.5pp).
181	
182	\paragraph{Truncation direction and budget curve.}
183	Tail-truncation dramatically outperforms head-truncation: tail-2048 exceeds head-2048 by 15.5--22.6pp across three models (Appendix~\ref{sec:trace_length_full}).
184	Figure~\ref{fig:budget_curve} reveals a sharp phase transition at 384$\to$512 tail tokens: all four models simultaneously jump +13.2--22.0pp, crossing from near-baseline to 93--98\%.
185	This threshold coincides with the globals module dump boundary (${\sim}$384 tokens), beyond which structured execution markers become visible (Table~\ref{tab:tail_cross_model}).
186	Beyond 512 tokens, all 12 model$\times$seed combinations converge into [93.61\%, 98.24\%] (Table~\ref{tab:tail512_seeds}).
187	\texttt{tail\_2048} captures 95--98\% of \texttt{exception\_only}'s accuracy; the residual 2--5pp gap shows semantic extraction still outperforms positional extraction.
188	
189	\begin{figure}[t]
190	\centering
191	\includegraphics[width=\columnwidth]{budget_curve}
192	\caption{Tail-truncation budget curve across four models and three architecture families ($N{=}1{,}190$). A sharp phase transition at 384$\to$512 tokens (+13.2--22.0pp) coincides with the globals module dump boundary. Dashed lines: \texttt{exception\_only} ceiling and \texttt{no\_trace} floor.}
193	\label{fig:budget_curve}
194	\end{figure}
195	
196	\paragraph{Calibration.}
197	\label{sec:calibration}
198	Calibration mirrors the tier hierarchy: \texttt{exception\_only} achieves ECE = 0.0027 vs.\ 0.171 for \texttt{no\_trace}, a 63$\times$ gap (Figure~\ref{fig:calibration}).
199	This calibration advantage generalizes across architectures and scales: all four models (1.5B--13B) achieve ECE ${<}$ 0.007 under \texttt{exception\_only} (Table~\ref{tab:calibration_model_level} in Appendix), indicating well-calibrated predictions rather than overfit confidence.
200	
201	\paragraph{Error analysis.}
202	\texttt{exception\_only}'s 2 errors have zero overlap with all other conditions' error sets (Jaccard = 0.000; Appendix~\ref{sec:error_overlap}); per-type breakdown shows all standard exception types achieve 100\% accuracy, with only \texttt{GeneratorExit} (a benign \texttt{BaseException} subclass) causing failures (Appendix~\ref{sec:exception_type}).
203	
204	\paragraph{Length control.}
205	Padding \texttt{exception\_only} to 2{,}048 tokens, even in a semantically loaded position (after the verdict region), yields identical accuracy (99.83\%), indicating the 18--23pp gap arises from spurious patterns in verbose trace content, not sequence length.
206	
207	\paragraph{Supplementary OOD analysis.}
208	\label{sec:debugbench}
209	On DebugBench \citep{tian2024debugbench} ($N{=}426$), the condition ranking is preserved: \texttt{exception\_only} 100\%, VOTA 99.77\%, \texttt{no\_trace} 96.71\%.
210	However, narrow margins (3.29pp headroom from \texttt{no\_trace}) limit discriminative power; this supplementary analysis preserves the ranking but cannot establish effect sizes comparable to the primary dataset (Appendix~\ref{sec:debugbench_full}).
211	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "60e6a3dd-20b2-4324-be7a-9e6180b92395",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/experiments.tex",
      "content": "\\section{Experiments}\n\nWe evaluate across two research questions:\n(1)~Why do complete traces degrade SFT verdict accuracy despite containing all diagnostic information?\n(2)~Which trace components carry the verdict signal, and how does their density affect learning?\nAll experiments use $N{=}1{,}190$ test samples; accuracy is reported with Wilson 95\\% CIs.\\footnote{Problem-level partition (472 train / 119 test, zero crossover; \\S\\ref{sec:dataset}). \\texttt{exception\\_only} duplicates (48.99\\% test; Appendix~\\ref{sec:dedup_stats}) arise from within-problem variants; deduplication yields negligible ($<$0.1pp) delta.}\nPairwise comparisons use paired bootstrap resampling ($B{=}10{,}000$, seed=42); all differences are significant at $p{<}.0001$ unless noted.\nUnder problem-level clustered bootstrap ($n_\\text{eff}{=}119$), all cross-tier gaps remain significant ($p{<}.001$); 3 of 80 within-tier pairwise comparisons lose significance after Holm--Bonferroni correction.\n\n\\subsection{Cross-Model Comparison}\n\\label{sec:cross_model}\n\nTable~\\ref{tab:cross_model} compares four models spanning an 8.7$\\times$ parameter range (1.5B--13B) and three architecture families under key conditions; single-seed entries are marked with $^\\dag$.\nRegex B5 (99.33\\%) exploits the \\texttt{[No exception data in trace]} format marker, providing a non-learned baseline; its collapse to 28.49\\% under marker removal (\\S\\ref{sec:nomarker}) shows the SFT advantage is not format-driven.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-model verdict accuracy (\\%, $N{=}1{,}190$) across four models (1.5B--13B) and three architecture families. Multi-seed entries report mean$\\pm$std over 2--3 seeds; $^\\dag$ = single seed (seed 42). Bold: best per model. Full per-seed breakdowns in Appendix~\\ref{sec:full_results}; per-class metrics in Appendix~\\ref{sec:per_class}.}\n\\label{tab:cross_model}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Condition} & \\textbf{Qwen-7B} & \\textbf{Qwen-1.5B} & \\textbf{CL-13B} & \\textbf{DS-6.7B} \\\\\n\\midrule\nexception\\_only & \\textbf{99.83}{\\scriptsize$\\pm$0.00} & \\textbf{99.83}{\\scriptsize$\\pm$0.00} & \\textbf{99.89}{\\scriptsize$\\pm$0.10} & \\textbf{99.39}{\\scriptsize$\\pm$0.10} \\\\\nae\\_only & 99.64{\\scriptsize$\\pm$0.49} & 98.83{\\scriptsize$\\pm$0.36} & 99.08{\\scriptsize$\\pm$0.00} & 98.53{\\scriptsize$\\pm$0.30} \\\\\nVOTA & 99.05{\\scriptsize$\\pm$0.38} & 99.54{\\scriptsize$\\pm$0.06} & 98.74{\\scriptsize$\\pm$0.24} & 99.25$^\\ddag$ \\\\\nloop\\_only & 86.05{\\scriptsize$\\pm$0.52} & 79.54{\\scriptsize$\\pm$1.42} & 77.40{\\scriptsize$\\pm$1.54} & 80.31{\\scriptsize$\\pm$1.65} \\\\\nfull\\_trace & 81.44{\\scriptsize$\\pm$1.11} & 77.06$^\\dag$ & 79.9$^\\S$ & 79.16$^\\dag$ \\\\\nno\\_trace & 75.13$^\\dag$ & 72.35{\\scriptsize$\\pm$4.48} & 76.47$^\\dag$ & 73.36$^\\dag$ \\\\\n\\midrule\nRegex B5 (marker) & \\multicolumn{4}{c}{99.33} \\\\\nMajority baseline & \\multicolumn{4}{c}{71.51} \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\vspace{2pt}\n\\par\\raggedright\\footnotesize\n$^\\ddag$DeepSeek VOTA seed 42 (84.45\\%) is a tokenizer-driven truncation failure (Appendix~\\ref{sec:tokenizer_analysis}), reported as 2-seed mean.\n$^\\S$CodeLlama \\texttt{full\\_trace} not available; head-2048 proxy reported.\nPer-seed breakdowns for all conditions in Appendix~\\ref{sec:full_results}.\n\\end{table}\n\n\\paragraph{Exception dominance across families.}\nUnder \\texttt{exception\\_only}, all four models achieve ${\\geq}$99.33\\% across all available seeds (Table~\\ref{tab:cross_model}), spanning only 0.50pp across architectures (the tightest of any condition).\nCodeLlama-13B seed 123 achieves 100\\%, indicating the 2 persistent errors (\\texttt{GeneratorExit}; Appendix~\\ref{sec:irreducible}) are convergence artifacts; 99.83\\% is a floor, not a ceiling.\n\n\\paragraph{Scale effects concentrate in Tier~2.}\nTier~1 signals are scale-invariant across 1.5B--13B (8.7$\\times$): both \\texttt{exception\\_only} and \\texttt{ae\\_only} span ${\\leq}$1.2pp.\n\\texttt{loop\\_only} spans 8.57pp, with CodeLlama-13B below Qwen-1.5B, suggesting architecture matters more than parameter count for lower-density signals.\nIn contrast, \\texttt{no\\_trace} scales with capacity (Figure~\\ref{fig:cross_scale}) and shows the highest seed variance ($\\sigma{=}$4.48pp).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig3_cross_model_gap}\n\\caption{Verdict accuracy vs.\\ model scale. \\texttt{exception\\_only} maintains ${\\geq}$99.33\\% regardless of scale, while \\texttt{no\\_trace} shows monotonic sensitivity (+4.12pp). \\texttt{nomarker} (markers removed) shows no scale degradation.}\n\\label{fig:cross_scale}\n\\end{figure}\n\n\\paragraph{VOTA cross-family variation.}\nExcluding outlier seeds, VOTA achieves ${\\geq}$98.57\\% across all four models (0.80pp range).\nDeepSeek seed 42 (84.45\\%) is a tokenizer-driven truncation failure (91.7\\% of samples exceed 2{,}048 tokens after tokenization; Appendix~\\ref{sec:tokenizer_analysis}), demonstrating that VOTA's longer sequences are sensitive to tokenizer efficiency: 1/4 models suffers catastrophic truncation under standard training length. \\texttt{exception\\_only}'s compact inputs (median 150 tokens) sidestep this vulnerability entirely.\n\n\\subsection{Component Ablation}\n\\label{sec:ablation}\n\nMulti-seed \\texttt{ae\\_only} ablations use Qwen-7B; \\texttt{loop\\_only} is evaluated across three models to test Tier~2 generalization (Table~\\ref{tab:cross_model}).\nTable~\\ref{tab:ablation} decomposes VOTA on Qwen-2.5-7B and reveals a two-tier hierarchy validated across all four models and three architecture families (Table~\\ref{tab:cross_model}): Tier~1 (${\\geq}$98.53\\%) and Tier~2 (77--86\\%) are separated by 12+pp with non-overlapping CIs.\n\n\\begin{table}[t]\n\\centering\n\\caption{Component ablation on Qwen-2.5-7B ($N{=}1{,}190$). Tier~1 signals achieve near-perfect accuracy; combining them (VOTA) slightly dilutes performance. Entries marked $^\\dag$/$^\\S$/$^\\ddag$ are 3-seed mean$\\pm$std; unmarked entries are single seed (seed 42). Per-seed breakdowns in Appendix~\\ref{sec:full_results}. Seed $\\sigma$ negatively correlates with density (0.00 for exception to 0.52 for loop).}\n\\label{tab:ablation}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Condition} & \\textbf{Components} & \\textbf{Acc (\\%)} & \\textbf{95\\% CI} & \\textbf{Tier} \\\\\n\\midrule\nae\\_only & assertion-point & 99.64$^\\dag$ & [99.26, 99.87] & 1 \\\\\nexception\\_only & exception events & \\textbf{99.83} & [99.58, 100.00] & 1 \\\\\nVOTA & exc+ae+loop & 99.05$^\\S$ & [98.49, 99.50] & --- \\\\\nVOTA\\_no\\_ae & exc+loop & 99.41 & [98.90, 99.80] & --- \\\\\nloop\\_only & loop compression & 86.05$^\\ddag$ & [83.97, 87.96] & 2 \\\\\nfull\\_trace & complete trace & 81.44{\\scriptsize$\\pm$1.11} & --- & --- \\\\\nno\\_trace & none & 75.13 & [72.77, 77.48] & --- \\\\\n\\midrule\nRegex (best) & exc.\\ type regex & 93.61 & --- & --- \\\\\n3-shot (Qwen-7B) & in-context learning & 90.84 & --- & --- \\\\\nZero-shot (4 models) & prompting & 51.0--93.5 & --- & --- \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\nTier~1 signals are individually sufficient: \\texttt{exception\\_only} (99.83\\%$\\pm$0.00) exceeds VOTA (99.05\\%$\\pm$0.38) by +0.78pp (2/3 seeds $p{<}.05$, all directionally consistent), implying that combining signals introduces noise.\nRemoving assertion points has no effect (\\texttt{VOTA\\_no\\_ae} = 99.41\\%, single seed), indicating exception dominance.\nIndividual exception subcomponents (type, stacktrace, message) each independently achieve ${\\geq}$99.50\\%, indicating that the binary presence of an exception event, rather than any specific subcomponent, drives Tier~1 performance (Appendix~\\ref{sec:exc_subcomponent}).\nThe Tier~1/2 boundary is unambiguous: the lowest Tier~1 condition (\\texttt{ae\\_only} on DeepSeek, 98.53\\%$\\pm$0.30, 2 seeds) exceeds the highest Tier~2 (\\texttt{loop\\_only} on Qwen-7B, 86.05\\%, CI [83.97, 87.96]) by 12.48\\,pp with non-overlapping CIs (gap statistic supports $k{=}2$ clusters, silhouette ${\\geq}$0.74).\nTier~2 \\texttt{loop\\_only} lifts over \\texttt{no\\_trace} are model-dependent: Qwen +10.92pp (7B) and +7.19pp (1.5B); DeepSeek +6.95pp; CodeLlama +0.93pp (n.s.).\n\\paragraph{Rule-based baseline comparison.}\nThe strongest non-trivial regex heuristic (B4: exception class name matching; Table~\\ref{tab:regex}) achieves 93.61\\% accuracy (F1=0.876), trailing SFT \\texttt{exception\\_only} (99.83\\%, F1=0.997) by 6.22pp (McNemar $p{<}.001$).\nThe gap concentrates on caught-exception boundary cases: regex flags all exception events as failures, while SFT learns to distinguish caught exceptions (benign, inside \\texttt{try/except}) from uncaught faults, correctly resolving 6/8 boundary samples (Appendix~\\ref{sec:regex_baselines}).\nAcross all formats, SFT outperforms the best applicable regex by +3.62--23.86pp (Appendix~\\ref{sec:regex_baselines}).\n\n\\paragraph{Zero-shot and few-shot LLM baselines.}\nZero-shot prompting spans 51.0--93.5\\% across four models (42.44pp range); three-shot ICL on Qwen-7B (90.84\\%) improves only 1.76pp.\nSFT compresses this range to 0.50pp (99.39--99.89\\%), closing a 6--49pp gap with 4,720 samples (Appendix~\\ref{sec:zeroshot_cross_model}).\n\\paragraph{Frontier model crossover.}\nTwo frontier models illustrate that SFT's advantage depends on input density: under \\texttt{no\\_trace}, GPT-4o (84.45\\%) and GPT-4.1 (77.31\\%) outperform SFT Qwen-7B (75.13\\%), but under \\texttt{exception\\_only} the ranking reverses (SFT 99.83\\% vs.\\ GPT-4o 87.98\\%).\nCompact diagnostic input unlocks SFT's full advantage over general reasoning capacity.\n\n\\subsection{Format Marker Ablation}\n\\label{sec:nomarker}\n\nThe \\texttt{exception\\_only} format includes a \\texttt{[No exception data in trace]} marker in all pass-class samples (regex baseline B5 exploits this for 99.33\\% accuracy; Appendix~\\ref{sec:regex_baselines}).\nTo quantify the marker's contribution, we retrain with all format markers removed (\\texttt{nomarker} condition).\n\nQwen-7B 3-seed mean: 97.65\\% $\\pm$ 0.96 (seeds 42/123/456: 96.55/98.32/98.07\\%), a drop of 2.18pp from \\texttt{exception\\_only} (99.83\\%).\nQwen-1.5B: 97.82\\%, drop of 2.01pp.\nThe marker contribution (${\\sim}$2pp) accounts for only ${\\sim}$9\\% of the total exception lift over \\texttt{no\\_trace} (24.70pp on 7B).\nRegex baselines illustrate this decomposition: B5 (\\texttt{[No exception data]}$\\to$pass, 99.33\\% with markers) collapses to 28.49\\% without markers, showing it is entirely format-dependent.\nThe strongest semantic regex B4 (exception class matching, 93.61\\%) is marker-invariant; SFT \\texttt{nomarker} (97.65\\%) exceeds it by 4.04pp, isolating the learned semantic contribution beyond pattern matching.\n\n\\paragraph{Cross-dataset transfer.}\nBidirectional evaluation demonstrates generalization: HumanEval${\\to}$MBPP \\texttt{exception\\_only} achieves 99.41\\% ($N{=}4{,}270$) and MBPP${\\to}$HumanEval achieves 100.0\\% ($N{=}1{,}640$), while \\texttt{no\\_trace} drops to near-majority baseline in both directions (70.56\\% vs.\\ 69.02\\% majority; 67.99\\% vs.\\ 61.65\\%).\nThe near-zero transfer loss for exception signals, across independently authored problem sets with no problem overlap, shows SFT learns language-level diagnostic patterns, not dataset-specific artifacts.\nUnder marker removal, cross-dataset accuracy drops to 95.5\\% ($-$3.9pp), indicating that the majority of cross-dataset transfer relies on learned diagnostic patterns rather than format markers.\n\n\\subsection{Decomposing the Full-Trace Degradation}\n\\label{sec:density}\n\nThe 18.07pp gap between \\texttt{exception\\_only} (99.83\\%) and \\texttt{full\\_trace} (81.76\\%) could reflect gradient dilution (diagnostic tokens are ${\\sim}$1/500 of full traces, diluting gradient signal during training) or content quality (verbose input buries diagnostic signals at inference).\n\n\\paragraph{Controlled gradient masking.}\nTo isolate gradient dilution, we mask 99.8\\% of gradient updates during \\texttt{exception\\_only} training, matching the diagnostic token ratio of full traces while preserving compact input.\nThis yields 99.22\\% (mean $-$0.61pp from \\texttt{exception\\_only}, 3 seeds), limiting gradient dilution to ${\\leq}$4\\% of the 18.07pp gap (Table~\\ref{tab:density}).\nThe gradient masking bound attributes the remaining ${\\geq}$96\\% to content quality (diagnostic signal density at inference), though forward-pass attention during masked training is an unquantified residual.\nNote that masking affects only the backward pass; the model still attends to all input tokens during the forward pass, so this bounds gradient dilution's contribution but does not rule out attention-based information flow as a residual confound.\n\n\\begin{table}[t]\n\\centering\n\\caption{Decomposition of the full-trace degradation (Qwen-7B). Gradient masking attributes ${\\leq}$4\\% to gradient dilution; the bound assigns the remainder to content quality, though forward-pass attention is a residual confound (\\S\\ref{sec:density}). Label-only loss provides a confounded but directionally consistent complementary estimate.}\n\\label{tab:density}\n\\small\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Condition} & \\textbf{Acc (\\%)} & \\textbf{$\\Delta$} \\\\\n\\midrule\nexception\\_only & 99.83{\\scriptsize$\\pm$0.00} & --- \\\\\n\\quad + grad mask (99.8\\%) & 99.22{\\scriptsize$\\pm$0.20}$^\\S$ & $-$0.61pp \\\\\nfull\\_trace & 81.76$^\\ddag$ & $-$18.07pp \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textit{Complementary (confounded):}} \\\\\nfull\\_trace + label-only loss & 85.94{\\scriptsize$\\pm$1.12} & +4.50pp$^\\dag$ \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{2pt}\n\\par\\raggedright\\footnotesize\n$^\\S$Mean $\\pm$ std over 3 seeds (42, 123, 456).\n$^\\ddag$Matched-seed baseline; 3-seed mean 81.44\\%$\\pm$1.11 (Table~\\ref{tab:cross_model}).\n$^\\dag$vs.\\ \\texttt{full\\_trace} (81.44\\%$\\pm$1.11); not significant under clustered bootstrap (95\\% CI [$-$0.6, +9.8]pp, $n_\\text{eff}{=}119$).\n\\end{table}\n\n\\paragraph{Complementary evidence.}\nLabel-only loss on full traces (+4.50pp, 3 seeds) yields a confounded upper bound of ${\\leq}$26\\% gradient contribution, consistent with the masking estimate (${\\leq}$4\\%) but not significant under clustered bootstrap (95\\% CI [$-$0.6, +9.8]pp).\nQwen-1.5B shows a similar label-only pattern (17\\%/83\\%, 3 seeds); CodeLlama and DeepSeek exhibit label-only collapse to majority baseline (28.5\\%), limiting this complementary analysis to the Qwen family.\nThe architecture dependence suggests label-only training is sensitive to model capacity or optimization landscape; the gradient masking ablation provides a more robust, architecture-independent decomposition.\nCross-architecture validation on two additional families is directionally consistent (single seed each): DeepSeek-Coder-6.7B achieves 99.33\\% and CodeLlama-13B achieves 100\\% under 99.8\\% masking, both well above the full-trace range (77--82\\%, Table~\\ref{tab:cross_model}), supporting content quality as the dominant factor across architectures.\nError analysis supports the content quality interpretation: all 217 \\texttt{full\\_trace} errors occur where tokenizer truncation removes diagnostic markers, manifesting through mechanical truncation rather than semantic confusion.\n\n\\subsection{Complementary Analyses}\n\\label{sec:additional}\n\n\\paragraph{Trace length ablation.}\n\\label{sec:trace_length}\nVarying the head-truncated trace token budget (256--no limit) on Qwen-7B yields accuracy in a narrow 77.2\\%--81.8\\% band with a non-monotonic pattern: 1024-token prefixes (77.23\\%) underperform 512-token prefixes (80.42\\%, $p{=}.002$), because mid-length prefixes retain enough irrelevant content to mislead the model while discarding diagnostic events near the trace terminus (Appendix~\\ref{sec:trace_length_full}).\nCritically, removing the token budget entirely (no truncation) yields 81.76\\%, identical to head-2048, ruling out truncation as the explanation for the full-trace degradation.\nThis non-monotonicity is specific to head-truncation; under tail-truncation, accuracy increases monotonically for two of three models (Table~\\ref{tab:tail_cross_model} in Appendix), with only DeepSeek showing a mild architecture-specific reversal at tail-1024$\\to$tail-2048 ($-$1.5pp).\n\n\\paragraph{Truncation direction and budget curve.}\nTail-truncation dramatically outperforms head-truncation: tail-2048 exceeds head-2048 by 15.5--22.6pp across three models (Appendix~\\ref{sec:trace_length_full}).\nFigure~\\ref{fig:budget_curve} reveals a sharp phase transition at 384$\\to$512 tail tokens: all four models simultaneously jump +13.2--22.0pp, crossing from near-baseline to 93--98\\%.\nThis threshold coincides with the globals module dump boundary (${\\sim}$384 tokens), beyond which structured execution markers become visible (Table~\\ref{tab:tail_cross_model}).\nBeyond 512 tokens, all 12 model$\\times$seed combinations converge into [93.61\\%, 98.24\\%] (Table~\\ref{tab:tail512_seeds}).\n\\texttt{tail\\_2048} captures 95--98\\% of \\texttt{exception\\_only}'s accuracy; the residual 2--5pp gap shows semantic extraction still outperforms positional extraction.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{budget_curve}\n\\caption{Tail-truncation budget curve across four models and three architecture families ($N{=}1{,}190$). A sharp phase transition at 384$\\to$512 tokens (+13.2--22.0pp) coincides with the globals module dump boundary. Dashed lines: \\texttt{exception\\_only} ceiling and \\texttt{no\\_trace} floor.}\n\\label{fig:budget_curve}\n\\end{figure}\n\n\\paragraph{Calibration.}\n\\label{sec:calibration}\nCalibration mirrors the tier hierarchy: \\texttt{exception\\_only} achieves ECE = 0.0027 vs.\\ 0.171 for \\texttt{no\\_trace}, a 63$\\times$ gap (Figure~\\ref{fig:calibration}).\nThis calibration advantage generalizes across architectures and scales: all four models (1.5B--13B) achieve ECE ${<}$ 0.007 under \\texttt{exception\\_only} (Table~\\ref{tab:calibration_model_level} in Appendix), indicating well-calibrated predictions rather than overfit confidence.\n\n\\paragraph{Error analysis.}\n\\texttt{exception\\_only}'s 2 errors have zero overlap with all other conditions' error sets (Jaccard = 0.000; Appendix~\\ref{sec:error_overlap}); per-type breakdown shows all standard exception types achieve 100\\% accuracy, with only \\texttt{GeneratorExit} (a benign \\texttt{BaseException} subclass) causing failures (Appendix~\\ref{sec:exception_type}).\n\n\\paragraph{Length control.}\nPadding \\texttt{exception\\_only} to 2{,}048 tokens, even in a semantically loaded position (after the verdict region), yields identical accuracy (99.83\\%), indicating the 18--23pp gap arises from spurious patterns in verbose trace content, not sequence length.\n\n\\paragraph{Supplementary OOD analysis.}\n\\label{sec:debugbench}\nOn DebugBench \\citep{tian2024debugbench} ($N{=}426$), the condition ranking is preserved: \\texttt{exception\\_only} 100\\%, VOTA 99.77\\%, \\texttt{no\\_trace} 96.71\\%.\nHowever, narrow margins (3.29pp headroom from \\texttt{no\\_trace}) limit discriminative power; this supplementary analysis preserves the ranking but cannot establish effect sizes comparable to the primary dataset (Appendix~\\ref{sec:debugbench_full}).\n",
      "numLines": 211,
      "startLine": 1,
      "totalLines": 211
    }
  }
}
```

</details>

---


### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Read · `toolu_01BTCgUja3EHjNDroavZh2z6`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "2aa5b4de-ece5-4c1e-a913-fb95b39e3a1d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012brTbzezUo9HdHSffBPKci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1489,
      "cache_read_input_tokens": 25293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1489
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

_source line 26 · 2026-05-23T19:17:31.855Z_

<details><summary>↩ Tool result · `toolu_01BTCgUja3EHjNDroavZh2z6`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{A descriptive two-pathway framework.}
5	The results suggest two independent signal pathways and a dilution mechanism that together explain why complete traces degrade SFT learning.
6	
7	\paragraph{Explicit pathway: diagnostic tokens.}
8	The diagnostic token ratio $d$ (\S2.1) correlates strongly with accuracy across five conditions, and all four models achieve near-perfect accuracy under \texttt{exception\_only} (Table~\ref{tab:cross_model}).
9	\texttt{ae\_only}, a strict superset, slightly underperforms (Table~\ref{tab:ablation}), indicating that additional content introduces noise even within exception events.
10	
11	\paragraph{Implicit pathway: terminal execution state.}
12	Tail-truncated traces achieve 93--98\% accuracy (Table~\ref{tab:tail_cross_model}) despite $d {\approx} 0$.
13	At ${\geq}$512 tokens (Figure~\ref{fig:budget_curve}), tail truncation captures \texttt{[Line~X]} variable values at final execution steps, which implicitly encode verdict direction; below 384 tokens, the globals module dump consumes the entire budget, yielding near-\texttt{no\_trace} performance.
14	
15	\paragraph{Diagnostic signal dilution in complete traces.}
16	Both pathways' signals exist in full traces but are buried under thousands of intermediate tokens.
17	Controlled gradient masking (\S\ref{sec:density}) attributes ${\leq}$4\% of the gap to gradient dilution, assigning the majority to content quality at inference: diagnostic tokens are too sparse for the model to reliably extract from verbose input.
18	Training dynamics (Appendix~\ref{sec:training_dynamics}) corroborate this: \texttt{exception\_only} converges within 50 steps while \texttt{full\_trace} oscillates without convergence.
19	
20	\paragraph{Why SFT over regex?}
21	The contribution is the diagnostic decomposition, not a prediction system; nonetheless, SFT dominates regex on every axis beyond raw accuracy.
22	SFT retains 97.65\% under marker removal while the regex collapses to 28.49\% (\S\ref{sec:nomarker}), provides 63$\times$ better calibration (\S\ref{sec:calibration}), and transfers bidirectionally across datasets with negligible loss.
23	
24	\paragraph{Design implications.}
25	Complete traces capture only 3--6pp of the ${\sim}$25pp headroom over source code alone, while exception events capture 23--27pp.
26	This runs counter to the field's operating assumption that more trace information should help \citep{chen2025tracepile,wang2025dcsh}; the magnitude and component decomposition are not predictable from information-theoretic priors alone.
27	The two-tier hierarchy suggests a practical fallback: extract exception events first; resort to tail-truncated state otherwise.
28	Tier~2 benefit is model-dependent (Qwen +10.9pp; CodeLlama +0.9pp), so trace design should match deployment model capacity.
29	
30	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "87515389-d568-47aa-bf89-f002db5ce37a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/discussion.tex",
      "content": "\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{A descriptive two-pathway framework.}\nThe results suggest two independent signal pathways and a dilution mechanism that together explain why complete traces degrade SFT learning.\n\n\\paragraph{Explicit pathway: diagnostic tokens.}\nThe diagnostic token ratio $d$ (\\S2.1) correlates strongly with accuracy across five conditions, and all four models achieve near-perfect accuracy under \\texttt{exception\\_only} (Table~\\ref{tab:cross_model}).\n\\texttt{ae\\_only}, a strict superset, slightly underperforms (Table~\\ref{tab:ablation}), indicating that additional content introduces noise even within exception events.\n\n\\paragraph{Implicit pathway: terminal execution state.}\nTail-truncated traces achieve 93--98\\% accuracy (Table~\\ref{tab:tail_cross_model}) despite $d {\\approx} 0$.\nAt ${\\geq}$512 tokens (Figure~\\ref{fig:budget_curve}), tail truncation captures \\texttt{[Line~X]} variable values at final execution steps, which implicitly encode verdict direction; below 384 tokens, the globals module dump consumes the entire budget, yielding near-\\texttt{no\\_trace} performance.\n\n\\paragraph{Diagnostic signal dilution in complete traces.}\nBoth pathways' signals exist in full traces but are buried under thousands of intermediate tokens.\nControlled gradient masking (\\S\\ref{sec:density}) attributes ${\\leq}$4\\% of the gap to gradient dilution, assigning the majority to content quality at inference: diagnostic tokens are too sparse for the model to reliably extract from verbose input.\nTraining dynamics (Appendix~\\ref{sec:training_dynamics}) corroborate this: \\texttt{exception\\_only} converges within 50 steps while \\texttt{full\\_trace} oscillates without convergence.\n\n\\paragraph{Why SFT over regex?}\nThe contribution is the diagnostic decomposition, not a prediction system; nonetheless, SFT dominates regex on every axis beyond raw accuracy.\nSFT retains 97.65\\% under marker removal while the regex collapses to 28.49\\% (\\S\\ref{sec:nomarker}), provides 63$\\times$ better calibration (\\S\\ref{sec:calibration}), and transfers bidirectionally across datasets with negligible loss.\n\n\\paragraph{Design implications.}\nComplete traces capture only 3--6pp of the ${\\sim}$25pp headroom over source code alone, while exception events capture 23--27pp.\nThis runs counter to the field's operating assumption that more trace information should help \\citep{chen2025tracepile,wang2025dcsh}; the magnitude and component decomposition are not predictable from information-theoretic priors alone.\nThe two-tier hierarchy suggests a practical fallback: extract exception events first; resort to tail-truncated state otherwise.\nTier~2 benefit is model-dependent (Qwen +10.9pp; CodeLlama +0.9pp), so trace design should match deployment model capacity.\n\n",
      "numLines": 30,
      "startLine": 1,
      "totalLines": 30
    }
  }
}
```

</details>

---


### Tool call

_source line 27_

<details open><summary>🔧 Tool call — Read · `toolu_0169Qrh5eSFXppqYpb3R2kjR`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "9f66c99b-1788-4085-bd55-c4f203ac0b10",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012brTbzezUo9HdHSffBPKci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1489,
      "cache_read_input_tokens": 25293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1489
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

_source line 28 · 2026-05-23T19:17:32.306Z_

<details><summary>↩ Tool result · `toolu_0169Qrh5eSFXppqYpb3R2kjR`</summary>

```text
1	\section{Conclusion}
2	
3	Across four code-specialized models (1.5B--13B), compact exception events (${\geq}$99.33\%) outperform complete traces (77--82\%) by 18--23pp; gradient masking (${\leq}$4\% dilution), cross-dataset transfer (99.4--100\%), and marker-removal robustness show that diagnostic density, not information quantity, drives SFT learning.
4	Practitioners should extract exception events first; tail-truncated traces (${\geq}$512 tokens) recover 93--98\% as fallback.
5	Whether models beyond 13B can overcome signal dilution in complete traces, and whether these findings extend to languages without Python's structured exception hierarchy, remain open questions.
6	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "2b707f46-1729-4f7c-aa88-e687d7e776b6",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\nAcross four code-specialized models (1.5B--13B), compact exception events (${\\geq}$99.33\\%) outperform complete traces (77--82\\%) by 18--23pp; gradient masking (${\\leq}$4\\% dilution), cross-dataset transfer (99.4--100\\%), and marker-removal robustness show that diagnostic density, not information quantity, drives SFT learning.\nPractitioners should extract exception events first; tail-truncated traces (${\\geq}$512 tokens) recover 93--98\\% as fallback.\nWhether models beyond 13B can overcome signal dilution in complete traces, and whether these findings extend to languages without Python's structured exception hierarchy, remain open questions.\n",
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

_source line 29_

<details open><summary>🔧 Tool call — Read · `toolu_015W8RShoAbFfpNBfzQWjU3R`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "08b391d6-a2dd-41a4-9c87-d6d39dd373ac",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012brTbzezUo9HdHSffBPKci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1489,
      "cache_read_input_tokens": 25293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1489
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

_source line 30 · 2026-05-23T19:17:33.575Z_

<details><summary>↩ Tool result · `toolu_015W8RShoAbFfpNBfzQWjU3R`</summary>

```text
1	\section{Per-Class Performance Breakdown}
2	\label{sec:per_class}
3	
4	Table~\ref{tab:per_class} reports per-class precision, recall, and F1 for all experimental conditions.
5	
6	\begin{table*}[t]
7	\centering
8	\caption{Per-class precision, recall, and F1 for all experimental conditions (seed 42). DeepSeek VOTA seed 42 is a training failure (84.45\%, fail recall = 45.4\%) due to tokenizer-driven truncation; seeds 123/456 achieve 99.16\%/99.33\%.}
9	\label{tab:per_class}
10	\small
11	\begin{tabular}{llccccccc}
12	\toprule
13	\textbf{Condition} & \textbf{Model} & \textbf{Acc} & \textbf{Pass P} & \textbf{Pass R} & \textbf{Pass F1} & \textbf{Fail P} & \textbf{Fail R} & \textbf{Fail F1} \\
14	\midrule
15	No Trace          & Qwen-2.5-7B & 75.13 & 87.76 & 75.79 & 81.34 & 54.73 & 73.45 & 62.72 \\
16	Full Trace        & Qwen-2.5-7B & 81.76 & 87.74 & 86.60 & 87.17 & 67.43 & 69.62 & 68.51 \\
17	Full Trace (LO)   & Qwen-2.5-7B & 85.94 & 88.21 & 93.18 & 90.63 & 80.07 & 68.73 & 73.97 \\
18	VOTA              & Qwen-2.5-7B & 99.05 & 100.00 & 99.18 & 99.59 & 97.98 & 100.00 & 98.98 \\
19	Exception Only    & Qwen-2.5-7B & 99.83 & 100.00 & 99.76 & 99.88 & 99.41 & 100.00 & 99.71 \\
20	AE Only           & Qwen-2.5-7B & 99.92 & 100.00 & 99.88 & 99.94 & 99.71 & 100.00 & 99.85 \\
21	Loop Only         & Qwen-2.5-7B & 86.05 & 92.39 & 87.07 & 89.66 & 71.65 & 82.01 & 76.48 \\
22	VOTA\_no\_ae       & Qwen-2.5-7B & 99.41 & 99.88 & 99.29 & 99.59 & 98.26 & 99.71 & 98.98 \\
23	\midrule
24	No Trace          & DeepSeek-6.7B & 73.36 & 81.71 & 80.85 & 81.28 & 53.16 & 54.57 & 53.86 \\
25	Full Trace        & DeepSeek-6.7B & 79.16 & 85.70 & 85.10 & 85.40 & 63.20 & 64.30 & 63.70 \\
26	VOTA              & DeepSeek-6.7B & 84.45 & 82.14 & 100.00 & 90.20 & 100.00 & 45.40 & 62.50 \\
27	Exception Only    & DeepSeek-6.7B & 99.33 & 100.00 & 99.06 & 99.53 & 97.69 & 100.00 & 98.83 \\
28	AE Only           & DeepSeek-6.7B & 98.74 & 98.40 & 99.90 & 99.10 & 99.70 & 95.90 & 97.70 \\
29	\bottomrule
30	\end{tabular}
31	\end{table*}
32	
33	%% ============================================================
34	\section{Training Details}
35	\label{sec:training_details}
36	
37	Table~\ref{tab:hyperparams} summarizes the training hyperparameters shared across all conditions.
38	All experiments use the HuggingFace TRL \texttt{SFTTrainer} with LoRA \citep{hu2022lora} applied to all linear layers.
39	
40	\begin{table}[t]
41	\centering
42	\caption{Training hyperparameters (shared across all conditions).}
43	\label{tab:hyperparams}
44	\small
45	\resizebox{\columnwidth}{!}{%
46	\begin{tabular}{ll}
47	\toprule
48	\textbf{Hyperparameter} & \textbf{Value} \\
49	\midrule
50	LoRA rank ($r$)            & 16 \\
51	LoRA alpha ($\alpha$)      & 32 \\
52	LoRA dropout               & 0.05 \\
53	LoRA target modules        & all linear layers \\
54	\midrule
55	Epochs                     & 3 \\
56	Per-device batch size       & 4 \\
57	Gradient accumulation steps & 8 \\
58	Effective batch size        & 32 \\
59	\midrule
60	Learning rate               & $2 \times 10^{-4}$ \\
61	LR scheduler                & linear decay \\
62	Warmup ratio                & 0.1 \\
63	Weight decay                & 0.01 \\
64	\midrule
65	Max sequence length         & 2048 tokens \\
66	Primary seed                & 42 \\
67	Robustness seeds            & 123, 456 \\
68	\midrule
69	Hardware                    & 1$\times$ enterprise-grade GPU (${\geq}$80\,GB VRAM) \\
70	Framework                   & HuggingFace TRL SFTTrainer \\
71	\bottomrule
72	\end{tabular}%
73	}
74	\end{table}
75	
76	Table~\ref{tab:train_time} reports per-condition training wall-clock times.
77	Conditions with longer trace inputs (e.g., \texttt{full\_trace}, VOTA) require proportionally more training time due to increased sequence lengths.
78	
79	\begin{table}[t]
80	\centering
81	\caption{Training wall-clock time per condition on a single enterprise-grade GPU (${\geq}$80\,GB VRAM). Where multiple seeds were run, individual times are listed.}
82	\label{tab:train_time}
83	\small
84	\begin{tabular}{llr}
85	\toprule
86	\textbf{Condition} & \textbf{Seed(s)} & \textbf{Time (h)} \\
87	\midrule
88	no\_trace       & 42         & ${\sim}$0.5 \\
89	full\_trace     & 42         & ${\sim}$2.2 \\
90	label\_only     & 42         & ${\sim}$2.2 \\
91	VOTA                     & 42         & ${\sim}$2.3 \\
92	exception\_only & 42         & ${\sim}$2.1 \\
93	exception\_only & 123        & ${\sim}$2.1 \\
94	exception\_only & 456        & ${\sim}$1.3 \\
95	ae\_only        & 42         & ${\sim}$1.8 \\
96	loop\_only      & 42         & ${\sim}$2.1 \\
97	VOTA\_no\_ae    & 42         & ${\sim}$1.8 \\
98	\bottomrule
99	\end{tabular}
100	\end{table}
101	
102	%% ============================================================
103	\section{VOTA Extraction Algorithm}
104	\label{sec:vota_algorithm}
105	
106	Algorithm~\ref{alg:vota} describes the three-component VOTA extraction pipeline applied to a raw \texttt{sys.settrace} execution log.
107	
108	\begin{algorithm}[t]
109	\caption{VOTA Trace Extraction}
110	\label{alg:vota}
111	\small
112	\begin{algorithmic}[1]
113	\REQUIRE Raw trace $T$ from \texttt{sys.settrace} (list of events)
114	\ENSURE Compressed VOTA representation $V$
115	\STATE $V \leftarrow$ empty string
116	\STATE \textbf{// Component 1: Exception summary}
117	\FOR{each event $e$ in $T$ with type \texttt{exception}}
118	  \STATE Parse traceback $\rightarrow$ extract error type, message, file, line
119	  \STATE Append \texttt{[ERROR] type: message (file:line)} to $V$
120	\ENDFOR
121	\IF{no exception events found}
122	  \STATE Append \texttt{[No exception data in trace]} to $V$
123	\ENDIF
124	\STATE \textbf{// Component 2: Assertion-point comparison}
125	\FOR{each \texttt{assert} or \texttt{return} event $e$ in $T$}
126	  \STATE Extract actual value from execution state
127	  \STATE Extract expected value from test assertion
128	  \STATE Append \texttt{[ASSERT] actual=... expected=... match=T/F} to $V$
129	\ENDFOR
130	\STATE \textbf{// Component 3: Loop compression}
131	\FOR{each consecutive repeated line sequence $S$ in $T$}
132	  \IF{$|S| \geq 2$ iterations of same loop body}
133	    \STATE Replace $S$ with single iteration + \texttt{[repeated $\times$N]}
134	  \ENDIF
135	\ENDFOR
136	\STATE Append compressed non-exception lines to $V$
137	\RETURN $V$
138	\end{algorithmic}
139	\end{algorithm}
140	
141	%% ============================================================
142	\section{VOTA Trace Examples}
143	\label{sec:vota_examples}
144	
145	We provide two representative VOTA trace examples illustrating the fail and pass cases.
146	In the fail case, the exception event provides an unambiguous fault signal.
147	In the pass case, the absence of an exception event combined with a matching assertion point confirms correct execution.
148	
149	\paragraph{Fail example.}
150	A \texttt{ZeroDivisionError} triggers an \texttt{[ERROR]} event, providing a direct fault signal that is sufficient for the model to predict \texttt{fail}.
151	
152	\begin{scriptsize}
153	\begin{verbatim}
154	## Function
155	def divide(a, b):
156	    return a / b
157	
158	## Test Input
159	divide(1, 0)
160	
161	## Expected Output
162	inf
163	
164	## VOTA Trace
165	[ERROR] ZeroDivisionError: division by zero
166	
167	## Verdict
168	fail
169	\end{verbatim}
170	\end{scriptsize}
171	
172	\paragraph{Pass example.}
173	No exception is raised, and the assertion point confirms that the actual output matches the expected value.
174	
175	\begin{scriptsize}
176	\begin{verbatim}
177	## Function
178	def add(a, b):
179	    return a + b
180	
181	## Test Input
182	add(2, 3)
183	
184	## Expected Output
185	5
186	
187	## VOTA Trace
188	[LOOP] No loops detected.
189	[ASSERT] actual=5, expected=5
190	
191	## Verdict
192	pass
193	\end{verbatim}
194	\end{scriptsize}
195	
196	These examples illustrate the core asymmetry exploited by the \texttt{exception\_only} condition: fail cases produce an explicit \texttt{[ERROR]} event, while pass cases are characterized by its absence.
197	This binary signal (presence vs.\ absence of an exception) is sufficient for near-perfect verdict prediction.
198	
199	%% ============================================================
200	\section{Full Experimental Results}
201	\label{sec:full_results}
202	
203	Tables~\ref{tab:full_qwen} and \ref{tab:full_deepseek} report the complete experimental results across all conditions, models, and seeds.
204	
205	\begin{table}[t]
206	\centering
207	\caption{Full results for Qwen-2.5-Coder-7B across all conditions and seeds. Conditions with a single seed report no variance. \texttt{exception\_only} achieves 99.83\% across all three seeds ($\sigma{=}$0). \texttt{ae\_only} achieves 99.64\% mean ($\pm$0.49; seed 123 at 99.08\% is the outlier).}
208	\label{tab:full_qwen}
209	\small
210	\resizebox{\columnwidth}{!}{%
211	\begin{tabular}{lcccc}
212	\toprule
213	\textbf{Condition} & \textbf{S42} & \textbf{S123} & \textbf{S456} & \textbf{Mean $\pm$ Std} \\
214	\midrule
215	exception\_only & 99.83 & 99.83 & 99.83 & 99.83 $\pm$ 0.00 \\
216	ae\_only        & 99.92 & 99.08 & 99.92 & 99.64 $\pm$ 0.49 \\
217	VOTA                     & 99.41 & 98.66 & 99.08 & 99.05 $\pm$ 0.38 \\
218	VOTA\_no\_ae    & 99.41 & ---   & ---   & --- \\
219	label\_only     & 86.22 & 86.89 & 84.70 & 85.94 $\pm$ 1.12 \\
220	loop\_only      & 85.63 & 85.88 & 86.64 & 86.05 $\pm$ 0.52 \\
221	full\_trace     & 81.76 & 80.20 & 82.35 & 81.44 $\pm$ 1.11 \\
222	no\_trace       & 75.13 & ---   & ---   & --- \\
223	\bottomrule
224	\end{tabular}%
225	}
226	\end{table}
227	
228	\begin{table}[t]
229	\centering
230	\caption{Full results for DeepSeek-Coder-6.7B across all conditions and seeds. \texttt{exception\_only} is consistent across seeds: 99.33/99.50/99.33 ($\sigma{=}$0.10pp).}
231	\label{tab:full_deepseek}
232	\small
233	\resizebox{\columnwidth}{!}{%
234	\begin{tabular}{llcc}
235	\toprule
236	\textbf{Condition} & \textbf{Seed} & \textbf{Accuracy} & \textbf{Notes} \\
237	\midrule
238	exception\_only & 42  & 99.33 & epoch 1: 99.83 \\
239	exception\_only & 456 & 99.33 & CI [98.82, 99.75] \\
240	exception\_only & 123 & 99.50 & \\
241	\midrule
242	VOTA                     & 42  & 84.45 & training failure; fail recall = 45.4\% \\
243	VOTA                     & 123 & 99.16 & \\
244	VOTA                     & 456 & 99.33 & \\
245	no\_trace       & 42  & 73.36 & \\
246	full\_trace     & 42  & 79.16 & CI [76.80, 81.30] \\
247	\bottomrule
248	\end{tabular}%
249	}
250	\end{table}
251	
252	%% ============================================================
253	\section{Tokenizer and Truncation Analysis}
254	\label{sec:tokenizer_analysis}
255	
256	DeepSeek VOTA seed 42 (84.45\%) is a training failure driven by tokenizer-induced truncation.
257	Re-evaluation of the seed 42 checkpoint with the standard max\_length=2048 yields 16\% accuracy, consistent with complete model collapse rather than marginal degradation.
258	The previously reported 84.45\% was obtained with max\_length=16384, which partially bypasses tokenizer truncation.
259	Seeds 123 and 456, evaluated under identical conditions, achieve 99.16\% and 99.33\% respectively.
260	The DeepSeek tokenizer averages 2{,}626 tokens per VOTA sample versus 1{,}929 for Qwen, causing 91.7\% of DeepSeek VOTA training samples to exceed the 2{,}048-token context window.
261	The training framework preserves the verdict label but truncates trace content, so the model trains with incomplete diagnostic information for the majority of samples.
262	Seeds 123 and 456 (99.16\% and 99.33\%) demonstrate that DeepSeek can learn VOTA when LoRA initialization avoids the truncation-sensitive basin; the 2-seed mean (99.25\%$\pm$0.12) matches the cross-model VOTA range (98.74--99.54\%).
263	
264	A post-hoc group analysis on seed 42 provides directional evidence: partitioning test samples by whether their training-set counterparts exceeded the context window, intact samples ($N{=}99$) achieve 100\% accuracy while truncated samples ($N{=}1{,}091$) achieve 83.04\% (95\% CI [80.75\%, 85.24\%]; Fisher exact $p{<}.001$), with all 185 errors concentrated in the fail class (fail recall = 31.23\%).
265	Per-class analysis (Table~\ref{tab:per_class}) shows that seed 42 achieves 100\% fail precision but only 45.43\% fail recall, systematically defaulting to \texttt{pass}.
266	
267	Seed robustness is consistent across models: Qwen \texttt{exception\_only} produces identical 99.83\% across all three seeds ($\sigma{=}0$), and DeepSeek achieves 99.39\%$\pm$0.10 (seeds 42/456: 99.33\%, seed 123: 99.50\%).
268	Because \texttt{exception\_only} test inputs contain 48.99\% duplicates (607 unique of 1,190; \S\ref{sec:dataset}), CIs assume $n{=}1{,}190$ independent trials; under deduplication ($n{=}607$), Qwen's accuracy is 99.67\% (Wilson CI [98.81, 99.91]).
269	
270	%% ============================================================
271	\section{Persistent Error Analysis}
272	\label{sec:irreducible}
273	
274	The \texttt{exception\_only} condition with Qwen-2.5-Coder-7B misclassifies exactly 2 out of 1,190 test samples across all three seeds (42, 123, 456), with 100\% overlap across seeds.
275	Both samples (IDs 901 and 905) share the following characteristics:
276	
277	\begin{itemize}
278	\item \textbf{Function:} \texttt{check\_dict\_case} (HumanEval/95), a function that checks whether all dictionary keys are uniformly upper-case or lower-case strings.
279	\item \textbf{Ground-truth label:} \texttt{pass}.
280	\item \textbf{Predicted label:} \texttt{fail} (false negative).
281	\item \textbf{Cross-seed consistency:} Both samples are misclassified identically by all three seeds, indicating a systematic rather than stochastic error.
282	\end{itemize}
283	
284	Manual inspection reveals the root cause: \texttt{check\_dict\_case} uses \texttt{all()} over a generator expression, and Python's \texttt{all()} short-circuits on the first \texttt{True} value, raising \texttt{GeneratorExit} to terminate the generator.
285	Because \texttt{GeneratorExit} is a \texttt{BaseException} subclass, the tracer records it as seven \texttt{[ERROR] GeneratorExit} lines, even though the function executes correctly and the test passes.
286	The model observes these spurious error markers and reasonably but incorrectly predicts \texttt{fail}.
287	This is not a model failure but a representation ambiguity: the \texttt{exception\_only} format cannot distinguish genuine exceptions from benign \texttt{BaseException} subclasses triggered by Python's iterator protocol.
288	
289	Most configurations converge to these same 2 errors: Qwen-1.5B, Qwen-7B (3 seeds), CodeLlama-13B (seeds 42/456), and DeepSeek-6.7B (seeds 42/456) all produce error set $\{901, 905\}$.
290	However, CodeLlama-13B seed 123 achieves 100\% accuracy (0/1190 errors), correctly classifying both samples.
291	This demonstrates that 99.83\% is a near-perfect \emph{floor} (the convergence attractor for most LoRA initializations) rather than a hard data ceiling: the representation supports perfect accuracy, but most initializations converge to the same 2-error basin.
292	The practical implication is that these errors are high-probability convergence artifacts addressable through seed selection or ensemble methods, not fundamental limitations of the exception-based representation.
293	
294	%% ============================================================
295	\section{Exception Type Accuracy Breakdown}
296	\label{sec:exception_type}
297	
298	Table~\ref{tab:exception_type} reports \texttt{exception\_only} accuracy stratified by exception type on Qwen-2.5-7B (seed=42, $N{=}1{,}190$).
299	All standard exception types (\texttt{TypeError}, \texttt{ValueError}, \texttt{IndexError}, etc.) achieve 100\% accuracy.
300	The only misclassifications arise from \texttt{GeneratorExit}, a \texttt{BaseException} subclass that is not an \texttt{Exception}. It is raised by Python's iterator protocol during generator short-circuiting, not by actual program errors.
301	
302	\begin{table}[t]
303	\centering
304	\caption{Exception type accuracy breakdown for \texttt{exception\_only} (Qwen-7B, seed=42). All true error types achieve 100\%. The only failures come from \texttt{GeneratorExit} (a \texttt{BaseException} subclass, not an \texttt{Exception}), which appears in 2 passing samples.}
305	\label{tab:exception_type}
306	\small
307	\begin{tabular}{lcc}
308	\toprule
309	\textbf{Exception Type} & \textbf{Samples} & \textbf{Accuracy} \\
310	\midrule
311	TypeError & 96 & 100\% \\
312	ValueError & 62 & 100\% \\
313	IndexError & 41 & 100\% \\
314	KeyError & 28 & 100\% \\
315	AttributeError & 19 & 100\% \\
316	AssertionError & 15 & 100\% \\
317	RecursionError & 12 & 100\% \\
318	Other Exception & 66 & 100\% \\
319	\midrule
320	GeneratorExit (BaseException) & 2 & 0\% \\
321	No exception (pass class) & 849 & 100\% \\
322	\bottomrule
323	\end{tabular}
324	\end{table}
325	
326	This is consistent with the model having learned a clean decision boundary: any true \texttt{Exception} subclass in the trace implies failure.
327	The \texttt{GeneratorExit} case represents a semantic ambiguity in the trace format rather than a model failure, as discussed in \S\ref{sec:irreducible}.
328	
329	%% ============================================================
330	\section{Exception Subcomponent Ablation}
331	\label{sec:exc_subcomponent}
332	
333	To test whether verdict prediction depends on a specific exception subcomponent or merely the binary presence of an exception event, we train Qwen-2.5-7B on three subcomponent-only conditions (seed 42, $N{=}1{,}190$).
334	
335	\begin{table}[t]
336	\centering
337	\caption{Exception subcomponent ablation (Qwen-2.5-7B, seed 42, $N{=}1{,}190$). All three subcomponents independently achieve ${\geq}$99.50\%. $^\dag$Retains \texttt{[ERROR]} format marker; $^\ddag$no format markers, bare exception class name only.}
338	\label{tab:exc_subcomponent}
339	\small
340	\begin{tabular}{lccc}
341	\toprule
342	\textbf{Condition} & \textbf{Acc (\%)} & \textbf{Fail R} & \textbf{Pass R} \\
343	\midrule
344	exc\_type\_only$^\dag$ & \textbf{100.00} & 100.00 & 100.00 \\
345	exc\_stacktrace\_only$^\dag$ & 99.83 & 100.00 & 99.76 \\
346	exc\_message\_only$^\ddag$ & 99.50 & 100.00 & 99.29 \\
347	\midrule
348	exception\_only (ref.) & 99.83 & 100.00 & 99.76 \\
349	\bottomrule
350	\end{tabular}
351	\end{table}
352	
353	All three subcomponents independently achieve ${\geq}$99.50\% with 100\% fail recall (Table~\ref{tab:exc_subcomponent}), showing that no single subcomponent is necessary for Tier~1 performance.
354	
355	\paragraph{Format marker confound.}
356	\texttt{exc\_type\_only} and \texttt{exc\_stacktrace\_only} retain the \texttt{[ERROR]} prefix marker present in the full \texttt{exception\_only} format; \texttt{exc\_message\_only} contains only the bare exception class name and message text without any format markers.
357	Because the marker alone is sufficient for near-perfect regex accuracy (B5: 99.33\%; \S\ref{sec:nomarker}), \texttt{exc\_type\_only} (100.00\%) and \texttt{exc\_stacktrace\_only} (99.83\%) are confounded with marker-based classification; we therefore do not make hierarchy claims among subcomponents.
358	\texttt{exc\_message\_only} (99.50\%) provides a clean test: without any format markers, it achieves accuracy comparable to the full \texttt{exception\_only} condition (99.83\%), complementing the dedicated marker-removal ablation (\texttt{nomarker}: 97.65\%; \S\ref{sec:nomarker}) as additional evidence that the model learns semantic exception patterns rather than format shortcuts.
359	
360	%% ============================================================
361	\section{Trace Length Ablation}
362	\label{sec:trace_length_full}
363	
364	To test whether the \texttt{full\_trace} performance gap is caused by input truncation at training time, we vary the maximum trace token budget on Qwen-2.5-7B (seed=42) while keeping all other hyperparameters fixed.
365	
366	\begin{table}[t]
367	\centering
368	\caption{Trace length and truncation direction ablation on Qwen-2.5-7B ($N{=}1{,}190$, seed=42). Head = standard left-truncation (retain first $k$ tokens); Tail = retain last $k$ tokens. Per-condition bootstrap 95\% CIs ($B{=}10{,}000$).}
369	\label{tab:trace_length}
370	\small
371	\begin{tabular}{llcc}
372	\toprule
373	\textbf{Direction} & \textbf{Max Tokens} & \textbf{Acc (\%)} & \textbf{95\% CI} \\
374	\midrule
375	Head & 256  & 78.82 & [76.4, 81.0] \\
376	Head & 512  & 80.42 & [78.2, 82.6] \\
377	Head & 1024 & 77.23 & [74.9, 79.6] \\
378	Head & no\_limit ($\infty$) & 81.76 & [79.7, 83.9] \\
379	\midrule
380	Tail & 256  & 77.48 & --- \\
381	Tail & 512  & 93.61 & --- \\
382	Tail & 1024 & 96.47 & --- \\
383	Tail & 2048 & 97.31 & --- \\
384	\bottomrule
385	\end{tabular}
386	\end{table}
387	
388	% Budget curve figure moved to main text (Figure~\ref{fig:budget_curve}).
389	
390	As shown in Table~\ref{tab:trace_length} and Figure~\ref{fig:budget_curve}, all four trace length conditions fall within a 5pp range (77.2\%--81.8\%).
391	To quantify the reliability of the observed differences, Table~\ref{tab:trace_length_pairwise} reports paired bootstrap comparisons ($B{=}10{,}000$, seed=42) across all condition pairs.
392	
393	\begin{table}[t]
394	\centering
395	\caption{Pairwise paired bootstrap comparisons for trace length ablation ($B{=}10{,}000$, seed=42). $\Delta$ = accuracy difference between the two conditions (first $-$ second in the budget group; condition $-$ baseline in the other groups). **$p{<}.01$; ***$p{<}.001$.}
396	\label{tab:trace_length_pairwise}
397	\small
398	\resizebox{\columnwidth}{!}{%
399	\begin{tabular}{llccc}
400	\toprule
401	& \textbf{Comparison} & \textbf{$\Delta$ (pp)} & \textbf{95\% CI} & \textbf{$p$-value} \\
402	\midrule
403	\multirow{4}{*}{\rotatebox{90}{\scriptsize Budget}}
404	& 512 vs.\ 256           & $+$1.60  & [$-$0.34, $+$3.53]   & 0.117 \\
405	& 1024 vs.\ 512          & $-$3.19  & [$-$5.29, $-$1.09]   & 0.002** \\
406	& no\_limit vs.\ 1024    & $+$4.54  & [$+$2.52, $+$6.55]   & ${<}$0.001*** \\
407	& no\_limit vs.\ 256     & $+$2.94  & [$+$0.84, $+$5.04]   & 0.006** \\
408	\midrule
409	\multirow{4}{*}{\rotatebox{90}{\scriptsize vs.\ no\_trace}}
410	& 256 $-$ no\_trace       & $+$3.70  & [$+$1.43, $+$6.05]   & 0.002** \\
411	& 512 $-$ no\_trace       & $+$5.29  & [$+$3.03, $+$7.56]   & ${<}$0.001*** \\
412	& 1024 $-$ no\_trace      & $+$2.10  & [$-$0.17, $+$4.37]   & 0.078 \\
413	& no\_limit $-$ no\_trace & $+$6.64  & [$+$4.37, $+$8.99]   & ${<}$0.001*** \\
414	\midrule
415	\multirow{4}{*}{\rotatebox{90}{\scriptsize vs.\ exc.}}
416	& 256 $-$ exc\_only       & $-$21.01 & [$-$23.45, $-$18.74] & ${<}$0.001*** \\
417	& 512 $-$ exc\_only       & $-$19.41 & [$-$21.76, $-$17.14] & ${<}$0.001*** \\
418	& 1024 $-$ exc\_only      & $-$22.61 & [$-$25.04, $-$20.25] & ${<}$0.001*** \\
419	& no\_limit $-$ exc\_only & $-$18.07 & [$-$20.34, $-$15.88] & ${<}$0.001*** \\
420	\bottomrule
421	\end{tabular}%
422	}
423	\end{table}
424	
425	\paragraph{Non-monotonic pattern (head-truncation).}
426	Under head-truncation (retaining trace prefixes), the trend is non-monotonic: 512 tokens (80.42\%) slightly outperforms 256 tokens (78.82\%), but doubling to 1024 tokens \emph{decreases} accuracy to 77.23\%, a statistically significant 3.19pp drop ($p{=}.002$, 95\% CI [$-$5.29, $-$1.09]).
427	The no-limit condition (81.76\%) recovers and significantly exceeds 1024 tokens ($p{<}.001$), but 1024 tokens is not significantly better than \texttt{no\_trace} (75.13\%; $\Delta{=}{+}2.10$pp, $p{=}.078$, 95\% CI [$-$0.17, $+$4.37]).
428	This non-monotonicity is specific to head-truncation: the 1024-token prefix retains enough irrelevant content to mislead the model while discarding diagnostic events that appear near the trace terminus.
429	Under tail-truncation, accuracy increases monotonically for Qwen-7B and Qwen-1.5B (Table~\ref{tab:tail_cross_model}); only DeepSeek-6.7B shows a mild $-$1.5pp decrease at tail-1024$\to$tail-2048, attributable to architecture-specific long-context sensitivity rather than a systematic mid-length pathology.
430	
431	\paragraph{Comparison to baselines.}
432	All four trace budget conditions significantly exceed \texttt{no\_trace} except 1024 tokens ($p{=}.078$), indicating that raw trace content provides some signal but unreliably so.
433	The gap to \texttt{exception\_only} (99.83\%) is massive for every budget condition (18--23pp, all $p{<}.001$), underscoring that even unlimited raw traces cannot substitute for targeted signal extraction.
434	The best full-trace condition (no\_limit, 81.76\%) still lags \texttt{exception\_only} by 18.07pp (95\% CI [$-$20.34, $-$15.88]).
435	
436	\paragraph{Interpretation.}
437	These results rule out input truncation as the primary explanation for the full-trace performance gap: even with unlimited tokens, the model cannot extract the diagnostic signal that VOTA's targeted compression provides.
438	The non-monotonic dip at 1024 tokens is consistent with a ``worst-of-both-worlds'' regime where the model receives enough noisy context to dilute the signal but not enough to compensate through broader coverage.
439	The result reinforces the information density interpretation (\S\ref{sec:density}): the gap between full traces and VOTA is driven by the \emph{content} of the trace (irrelevant lines diluting the diagnostic signal), not its \emph{length}.
440	In contrast, VOTA's compressed representation concentrates the diagnostic signal into fewer tokens, making it sensitive to truncation when those tokens are removed (\S\ref{sec:cross_model}).
441	
442	\paragraph{Truncation direction.}
443	Tail-truncation (retaining the last $k$ tokens) dramatically outperforms head-truncation: \texttt{tail\_2048} achieves 97.31\% vs.\ \texttt{head\_2048} (no\_limit) at 81.76\%, a 15.55pp improvement.
444	Even \texttt{tail\_512} (93.61\%) exceeds every head-truncation condition by over 11pp.
445	
446	However, \texttt{tail\_256} (77.48\%) performs at the \texttt{no\_trace} baseline level (75.13\%), indicating that the diagnostic signal does not reside in the very last trace lines.
447	The critical jump occurs between 256 and 512 tail tokens (+16.13pp), localizing the signal window to approximately 256--512 tokens from the trace terminus.
448	This is consistent with the trace format: the globals module dump consumes the first ${\sim}$384 tail tokens (pure noise), so structured execution markers (\texttt{[Line~X]} variable values) only become visible when the budget exceeds this threshold.
449	
450	The 18.07pp gap from \texttt{full\_trace} to \texttt{exception\_only} decomposes as: 86\% positional concentration (recovered by tail-truncation at 2048 tokens) and 14\% residual content noise (the 2.52pp gap from \texttt{tail\_2048} to \texttt{exception\_only} that persists regardless of truncation direction).
451	The fact that \texttt{exception\_only} (99.83\%) still outperforms \texttt{tail\_2048} (97.31\%) indicates that semantic extraction (identifying the exception type and message) is superior to positional extraction (keeping a fixed window), because the model need not filter out non-diagnostic lines that happen to fall within the window.
452	
453	\paragraph{Cross-model budget curve.}
454	Table~\ref{tab:tail_cross_model} extends the tail-truncation analysis to a full budget sweep across four models spanning three architecture families and an 8.7$\times$ parameter range.
455	
456	\begin{table}[t]
457	\centering
458	\caption{Cross-model tail-truncation budget curve ($N{=}1{,}190$). All four models exhibit a transition between tail-384 and tail-512 (+11--22pp). $\downarrow$: non-monotonic decrease. $^\dag$CodeLlama tail-384/512/1024 trained with label-only loss to address tokenizer-driven gradient dilution (\S\ref{sec:tokenizer_analysis}); tail-1024 reports best-epoch accuracy (epoch 1). CodeLlama tail entries are not directly comparable to other models (which use full-sequence loss). $^\ddag$CodeLlama tail-2048 outlier (41.8\%): LoRA long-sequence instability under label-only loss; excluded from cross-model analysis.}
459	\label{tab:tail_cross_model}
460	\small
461	\resizebox{\columnwidth}{!}{%
462	\begin{tabular}{lcccccc}
463	\toprule
464	\textbf{Model} & \textbf{tail-256} & \textbf{tail-384} & \textbf{tail-512} & \textbf{tail-1024} & \textbf{tail-2048} & \textbf{exc\_only} \\
465	\midrule
466	Qwen-7B (7B) & 78.9 & 79.9 & 93.6 & 96.5 & 97.3 & 99.83 \\
467	DeepSeek (6.7B) & 76.4 & 80.7 & 93.9 & 96.5 & 95.0$\downarrow$ & 99.33 \\
468	CodeLlama (13B) & 77.9 & 82.7$^\dag$ & 98.2$^\dag$ & 98.2$^\dag$ & 41.8$^\ddag$ & 99.89 \\
469	Qwen-1.5B (1.5B) & 72.6 & 73.6 & 95.6 & 96.6 & 97.9 & 99.83 \\
470	\bottomrule
471	\end{tabular}%
472	}
473	\end{table}
474	
475	\begin{table}[t]
476	\centering
477	\caption{Cross-model truncation direction comparison ($N{=}1{,}190$). Head-truncation retains the first 2,048 tokens; tail-truncation retains the last 2,048. All four models' head-2048 accuracies converge into a narrow 75.3--81.8\% band (6.5pp), comparable to the tail-256 signal-poor band (72.6--78.9\%, 6.3pp). $^\dag$CodeLlama tail-2048 pending retraining (\S\ref{sec:tokenizer_analysis}).}
478	\label{tab:head_vs_tail}
479	\small
480	\resizebox{\columnwidth}{!}{%
481	\begin{tabular}{lccc}
482	\toprule
483	\textbf{Model} & \textbf{head-2048 (\%)} & \textbf{tail-2048 (\%)} & \textbf{Gap (pp)} \\
484	\midrule
485	Qwen-1.5B & 75.3 & 97.9 & +22.6 \\
486	DeepSeek-6.7B & 78.7 & 95.0 & +16.3 \\
487	CodeLlama-13B & 79.9 & ---$^\dag$ & ---$^\dag$ \\
488	Qwen-7B & 81.8 & 97.3 & +15.5 \\
489	\bottomrule
490	\end{tabular}%
491	}
492	\end{table}
493	
494	Four patterns emerge from the budget curve.
495	\emph{Phase transition between 384 and 512 tokens}: the tail-384 column reveals that the transition is not instantaneous at 256$\to$512 but localized between 384 and 512 tokens.
496	At tail-384, all four models remain near baseline (73.6--80.7\%), gaining only +1.0--4.8pp over tail-256.
497	The steep jump occurs at 384$\to$512: +13.7pp (Qwen-7B), +13.2pp (DeepSeek), +15.5pp (CodeLlama), +22.0pp (Qwen-1.5B), crossing from near-baseline to near-ceiling.
498	This localizes the critical threshold to ${\sim}$400--500 tokens: below ${\sim}$384 tokens, the entire token budget is consumed by globals module dumps (pure noise); above ${\sim}$512, at least one \texttt{[Line~X]} execution event marker becomes visible, regardless of model capacity or architecture.
499	
500	\emph{Convergence at tail-512+}: once the sharp performance jump is crossed, accuracy converges across all models into a 93.6--98.2\% band at tail-512 (seed 42).
501	Multi-seed validation shows robustness: across all 12 model$\times$seed combinations at tail-512 (Table~\ref{tab:tail512_seeds}), all accuracies fall within [93.61\%, 98.24\%], a 4.63pp band that compresses the signal-poor tail-256 spread (6.3pp) by 27\%.
502	CodeLlama-13B shows perfect per-model convergence at tail-512: all three seeds achieve 98.24\% ($\sigma{=}$0), consistent with the 13B scale and label-only loss providing a stronger optimization signal in the signal-rich regime (Table~\ref{tab:tail512_seeds}).
503	However, CodeLlama's higher tail-512 accuracy may partly reflect label-only loss rather than model capacity; direct comparison with other models (which use full-sequence loss) is confounded by this training difference.
504	
505	\begin{table}[t]
506	\centering
507	\caption{Cross-seed convergence at the tail-512 truncation point ($N{=}1{,}190$ per seed). All 12 model$\times$seed combinations fall within a 4.63pp band [93.61\%, 98.24\%]. CodeLlama-13B achieves identical accuracy across all three seeds ($\sigma{=}$0).}
508	\label{tab:tail512_seeds}
509	\small
510	\resizebox{\columnwidth}{!}{%
511	\begin{tabular}{lccccr}
512	\toprule
513	\textbf{Model} & \textbf{S42} & \textbf{S123} & \textbf{S456} & \textbf{Mean} & \textbf{$\sigma$} \\
514	\midrule
515	Qwen-7B (7B)      & 93.61 & 96.00 & 97.65 & 95.75 & 2.05 \\
516	DeepSeek (6.7B)    & 93.95 & 95.04 & 96.10 & 95.03 & 1.08 \\
517	Qwen-1.5B (1.5B)  & 95.63 & 97.65 & 96.72 & 96.67 & 1.01 \\
518	CodeLlama (13B)    & 98.24 & 98.24 & 98.24 & \textbf{98.24} & \textbf{0.00} \\
519	\midrule
520	\multicolumn{4}{l}{Cross-model band} & \multicolumn{2}{r}{[93.61, 98.24] = 4.63pp} \\
521	\bottomrule
522	\end{tabular}%
523	}
524	\end{table}
525	
526	At tail-1024, four models reach 96.5--98.2\% (CodeLlama 98.2\% under label-only loss, three others 96.5--96.6\%).
527	Scale and architecture differences that dominate the signal-poor regime (tail-256 range: 72.6--78.9\%, 6.3pp) compress dramatically in the signal-rich regime.
528	
529	\emph{Signal-poor convergence band}: head-2048 accuracies across all four models also converge into a narrow 75.3--81.8\% band (6.5pp; Table~\ref{tab:head_vs_tail}), comparable in width to the tail-256 band (72.6--78.9\%, 6.3pp).
530	When the diagnostic signal is absent (head-truncation discards trace terminus) or unreachable (tail-256 is too short), models of different scale and architecture collapse to similar performance, suggesting a shared floor determined by code comprehension rather than trace processing.
531	
532	\emph{Scale behavior inversion}: in the signal-poor regime (tail-256), smaller models perform worse (Qwen-1.5B 72.6\% vs.\ Qwen-7B 78.9\%, $-$6.3pp), mirroring the \texttt{no\_trace} scale pattern.
533	In the signal-rich regime (tail-512+), this reverses: Qwen-1.5B matches or exceeds Qwen-7B (95.6\% vs.\ 93.6\% at tail-512; 97.9\% vs.\ 97.3\% at tail-2048), consistent with sufficient trace signal eliminating the capacity advantage.
534	
535	\emph{Non-monotonicity at long sequences}: two models show accuracy decreases beyond tail-1024.
536	DeepSeek-6.7B drops $-$1.5pp from tail-1024 (96.5\%) to tail-2048 (95.0\%), consistent with its known long-context sensitivity (\S\ref{sec:training_dynamics}).
537	CodeLlama-13B exhibits a more severe collapse: tail-2048 under label-only loss drops to 41.8\% (vs.\ tail-1024 = 98.2\%), which we attribute to LoRA long-sequence instability under the label-only loss regime; this outlier is excluded from cross-model tail-2048 analysis.
538	Qwen-7B and Qwen-1.5B increase monotonically across all budgets.
539	
540	Table~\ref{tab:head_vs_tail} shows the truncation direction effect: among the three models with complete data, tail-2048 outperforms head-2048 by 15.5--22.6pp.
541	The gap is largest for Qwen-1.5B (+22.6pp), indicating that smaller models benefit most from positional proximity to the diagnostic signal, as they lack the capacity to locate it within longer, noisier prefixes.
542	
543	%% ============================================================
544	\section{Calibration Analysis}
545	\label{sec:calibration_full}
546	
547	Beyond accuracy, we evaluate whether trace conditions affect prediction calibration, motivated by recent findings that code LLM confidence is often poorly calibrated \citep{spiess2025calibration}.
548	
549	\begin{table}[t]
550	\centering
551	\caption{Calibration metrics on Qwen-2.5-7B ($N{=}1{,}190$, seed=42). ECE = expected calibration error; Brier = Brier score. Lower is better for both.}
552	\label{tab:calibration}
553	\small
554	\begin{tabular}{lcc}
555	\toprule
556	\textbf{Condition} & \textbf{ECE $\downarrow$} & \textbf{Brier $\downarrow$} \\
557	\midrule
558	ae\_only & \textbf{0.0004} & \textbf{0.0008} \\
559	exception\_only & 0.0027 & 0.0013 \\
560	VOTA & 0.0054 & 0.005 \\
561	full\_trace & 0.096 & 0.144 \\
562	no\_trace & 0.171 & 0.197 \\
563	\bottomrule
564	\end{tabular}
565	\end{table}
566	
567	Table~\ref{tab:calibration} shows that calibration quality mirrors the Tier~1/2 hierarchy.
568	Tier~1 conditions (\texttt{ae\_only}: ECE=0.0004; \texttt{exception\_only}: ECE=0.0027) produce near-perfectly calibrated predictions, while \texttt{full\_trace} (ECE=0.096) and \texttt{no\_trace} (ECE=0.171) exhibit substantial miscalibration.
569	VOTA (ECE=0.0054) is well-calibrated but slightly worse than either Tier~1 component alone, reinforcing the pattern that combining trace signals dilutes rather than improves the prediction signal.
570	
571	The Brier scores tell a consistent story: \texttt{ae\_only} (0.0008) and \texttt{exception\_only} (0.0013) achieve near-zero scores, while \texttt{no\_trace} (0.197) indicates substantial miscalibration.
572	
573	\paragraph{Cross-model calibration.}
574	Table~\ref{tab:calibration_cross} extends the calibration analysis to four models (1.5B--13B) under \texttt{exception\_only}.
575	All four models achieve ECE ${<}$ 0.007 and Brier ${<}$ 0.007, indicating that calibration quality generalizes across architectures and scales.
576	CodeLlama-13B achieves the lowest ECE (0.0020) and MCE (0.0411), while DeepSeek-6.7B shows the highest ECE (0.0064) and Brier (0.0061), consistent with its higher error rate (8 errors vs.\ 2 for Qwen/CodeLlama).
577	
578	\begin{table}[t]
579	\centering
580	\caption{Cross-model calibration for \texttt{exception\_only} ($N{=}1{,}190$, seed=42). ECE = expected calibration error; Brier = Brier score; MCE = maximum calibration error. All four models (1.5B--13B) achieve ECE ${<}$ 0.007.}
581	\label{tab:calibration_cross}
582	\small
583	\begin{tabular}{lccc}
584	\toprule
585	\textbf{Model} & \textbf{ECE $\downarrow$} & \textbf{Brier $\downarrow$} & \textbf{MCE $\downarrow$} \\
586	\midrule
587	Qwen-1.5B & \textbf{0.0020} & \textbf{0.0013} & --- \\
588	CodeLlama-13B & \textbf{0.0020} & \textbf{0.0013} & \textbf{0.0411} \\
589	Qwen-7B & 0.0027 & \textbf{0.0013} & 0.8355 \\
590	DeepSeek-6.7B & 0.0064 & 0.0061 & 0.7756 \\
591	\bottomrule
592	\end{tabular}
593	\end{table}
594	
595	\begin{figure}[t]
596	\centering
597	\includegraphics[width=\columnwidth]{fig2_calibration}
598	\caption{Reliability diagrams for four trace conditions on Qwen-2.5-7B ($N{=}1{,}190$, seed=42). \texttt{exception\_only} (ECE=0.0027) clusters near the diagonal, while \texttt{no\_trace} (ECE=0.171) exhibits systematic overconfidence, a 63$\times$ gap.}
599	\label{fig:calibration}
600	\end{figure}
601	
602	%% ============================================================
603	\section{Error Overlap Analysis}
604	\label{sec:error_overlap}
605	
606	We analyze the overlap between error sets of different conditions to determine whether they fail on the same samples (Figure~\ref{fig:error_overlap}).
607	
608	\texttt{exception\_only}'s 2 errors (samples 901 and 905) have zero intersection with the error sets of all other conditions (Jaccard = 0.000 in all pairwise comparisons).
609	This orthogonality arises because \texttt{exception\_only} errors are caused by \texttt{GeneratorExit} false positives (pass samples misclassified as fail due to benign \texttt{BaseException} events), while errors from other conditions are predominantly fail samples misclassified as pass due to insufficient signal.
610	
611	Among non-exception conditions, error sets exhibit hierarchical containment: \texttt{ae\_only} $\subset$ VOTA $\subset$ \texttt{loop\_only} $\subset$ \texttt{no\_trace}, with pairwise Jaccard indices increasing with signal overlap.
612	\texttt{loop\_only} and \texttt{full\_trace} share the highest overlap (Jaccard ${\sim}$0.65), reflecting their shared reliance on behavioral patterns rather than explicit fault indicators.
613	
614	This analysis indicates that \texttt{exception\_only} operates on an independent signal dimension: its errors are representation ambiguities (iterator protocol artifacts) rather than information deficits, explaining why combining it with other signals cannot eliminate these specific errors.
615	
616	\begin{figure}[t]
617	\centering
618	\includegraphics[width=\columnwidth]{error_overlap}
619	\caption{Jaccard similarity between error sets of different conditions (Qwen-7B, seed=42, $N{=}1{,}190$). \texttt{exception\_only} (exc\_only) has zero overlap with all other conditions, indicating it operates on an independent signal dimension.}
620	\label{fig:error_overlap}
621	\end{figure}
622	
623	%% ============================================================
624	\section{Cross-Dataset Generalization: DebugBench}
625	\label{sec:debugbench_full}
626	
627	To test whether exception-based verdict prediction generalizes beyond LLM-generated solutions, we evaluate on DebugBench \citep{tian2024debugbench}, a dataset of human-written programs with synthetically injected bugs (single-point mutations such as operator replacement, variable misuse, and missing statements).
628	After filtering for executable Python samples with valid traces, we retain 426 samples with a near-balanced class distribution (majority baseline: 51.4\%).
629	
630	\begin{table}[t]
631	\centering
632	\caption{Generalization to DebugBench ($N{=}426$, Qwen-2.5-7B, seed=42). Wilson 95\% CIs. The component ranking (exception\_only $\geq$ VOTA $>$ no\_trace) is preserved, and exception\_only achieves perfect accuracy.}
633	\label{tab:debugbench}
634	\small
635	\begin{tabular}{lcc}
636	\toprule
637	\textbf{Condition} & \textbf{Acc (\%)} & \textbf{95\% CI} \\
638	\midrule
639	exception\_only & \textbf{100.00} & [99.14, 100.00] \\
640	VOTA & 99.77 & [99.30, 100.00] \\
641	no\_trace & 96.71 & [94.80, 98.40] \\
642	\midrule
643	Majority baseline & 51.41 & --- \\
644	\bottomrule
645	\end{tabular}
646	\end{table}
647	
648	Table~\ref{tab:debugbench} shows that the component ranking from the main experiments is preserved: \texttt{exception\_only} (100.00\%) $\geq$ VOTA (99.77\%) $>$ \texttt{no\_trace} (96.71\%).
649	The \texttt{exception\_only} condition achieves perfect accuracy, showing that the exception-based representation generalizes to a different fault distribution without degradation.
650	
651	The absolute margins are much narrower than on the main dataset: the \texttt{no\_trace} baseline already achieves 96.71\% (compared to 75.13\% on HumanEval+MBPP), leaving only 3.29pp of headroom for trace-based improvement.
652	This ceiling effect reflects a fundamental difference in fault characteristics: DebugBench bugs are synthetically injected single-point mutations, which produce code that is structurally dissimilar from the original correct solution; a model can often identify the fault from source code alone.
653	In contrast, the HumanEval+MBPP solutions are LLM-generated, producing natural errors (logic mistakes, edge-case failures) where the faulty and correct solutions may be structurally similar, making code-only verdict prediction substantially harder.
654	
655	These results support exception-based verdict prediction as a generalizable approach: the method does not degrade on an out-of-distribution dataset, and the exception dominance ranking (exception\_only $\geq$ VOTA $>$ no\_trace) is consistent across both datasets. However, the narrow DebugBench margins are insufficient to independently validate trace importance.
656	The 24.70pp trace lift on the main dataset (no\_trace 75.13\% $\to$ exception\_only 99.83\%) remains the primary evidence for the value of exception-based trace signals.
657	
658	%% ============================================================
659	\section{Cross-Model Robustness Analysis}
660	\label{sec:robustness_analysis}
661	
662	The cross-model gap pattern (Table~\ref{tab:cross_model}) suggests a design principle: \emph{trace representations should match the model capability floor, not the ceiling.}
663	Exception events are consistently the most effective component on both models, and their structural simplicity (a fixed-format error message) ensures that the relative advantage over richer representations holds across all seeds.
664	All three DeepSeek \texttt{exception\_only} seeds achieve ${\geq}$99.33\% (99.33/99.50/99.33, $\sigma{=}$0.10pp), matching Qwen and CodeLlama at ${\geq}$99.83\%.
665	VOTA achieves ${\geq}$98.57\% across all models when excluding outlier seeds (cross-model range: 0.80pp), but DeepSeek VOTA exhibits seed-dependent instability: seed 42 (84.45\%) is a training failure due to tokenizer-induced truncation (91.7\% of training samples affected), while seeds 123/456 (99.16\%/99.33\%) match cross-model performance.
666	This VOTA instability is confounded by tokenizer efficiency and base model differences \citep{yang2024generalization}.
667	Our \texttt{exception\_only} design sidesteps the truncation confound entirely: inputs have a median of 150 tokens (mean 398), well below the 2{,}048-token context window, so no training samples are truncated on either model.
668	The resulting 0.50pp cross-model gap (Table~\ref{tab:cross_model}) is therefore a clean measure of model capability differences, making the ``capability floor'' principle directly testable.
669	The practical implication is that trace-based systems should default to the simplest sufficient signal.
670	
671	%% ============================================================
672	\section{Training Dynamics and Loss Decoupling}
673	\label{sec:training_dynamics}
674	
675	\begin{figure}[t]
676	\centering
677	\includegraphics[width=\columnwidth]{training_dynamics}
678	\caption{Training dynamics: \texttt{exception\_only} converges to 99.83\% by step 150; \texttt{full\_trace} with label-only loss oscillates (82--89\%) without convergence.}
679	\label{fig:training_dynamics}
680	\end{figure}
681	
682	The DeepSeek \texttt{exception\_only} results are consistent across all three seeds (99.33/99.50/99.33, $\sigma{=}$0.10pp), matching Qwen's cross-seed stability.
683	Epoch-level analysis shows mild degradation in seed 42: accuracy peaks at 99.83\% after epoch~1 but settles at 99.33\% by epoch~3 ($-$0.50pp), while seed 456 shows no degradation (99.33\% at both epochs).
684	Early stopping may yield marginal gains, but the epoch effect is small (${\leq}$0.5pp).
685	The practical recommendation: for deployment, use task-specific metrics (accuracy, fail recall) for checkpoint and seed selection rather than training loss, and train multiple seeds to select the best.
686	
687	The contrast with VOTA is instructive: DeepSeek VOTA seed 42 accuracy monotonically increases from 78.15\% to 84.45\% across epochs, consistent with a performance limit from high trace truncation (91.7\% of samples; \S\ref{sec:tokenizer_analysis}).
688	Seeds 123/456, which avoid the truncation-sensitive initialization basin, achieve 99.16\%/99.33\%, indicating that the deficit is seed-specific rather than a fundamental model limitation.
689	
690	%% ============================================================
691	\section{Deduplication Statistics}
692	\label{sec:dedup_stats}
693	
694	Table~\ref{tab:dedup} reports the duplication rates across trace formats.
695	Because multiple passing solutions to the same problem produce identical (input, output) pairs in the \texttt{exception\_only} format (correct executions raise no exceptions, so the trace content is the same regardless of the solution's internal logic), the dataset contains duplicate rows.
696	Train--test input overlap is zero (split by problem ID), so no information leakage occurs.
697	The high duplication in \texttt{exception\_only} does not affect our experimental conclusions: after deduplication the training set still contains 2,858 unique samples and the test set 607, providing sufficient coverage for the 591-problem benchmark.
698	
699	\paragraph{Problem-level partitioning and sensitivity analysis.}
700	Data is partitioned at the problem level: 472 training problems and 119 test problems, with zero crossover.
701	Duplicates arise from multiple candidate solutions per problem (up to 10 solutions each), not from cross-problem overlap.
702	To verify that deduplication does not alter any finding, we ran a sensitivity analysis across all 19 experimental conditions (7 trace formats $\times$ 4 models, minus conditions not run): deduplication produces a negligible ($<$0.1pp) accuracy delta in every case.
703	This shows that duplicate samples neither inflate nor deflate accuracy, because duplicates share the same ground-truth label and the model's prediction is deterministic at inference time.
704	Duplicates arise because the \texttt{exception\_only} format collapses passing solutions (which share identical ``no exception'' output) into identical rows; the redundancy is a property of the format's compactness for pass-class samples.
705	The \texttt{exception\_only} test set contains 48.99\% such duplicates; all confidence intervals treat samples as independent Bernoulli trials.
706	
707	\begin{table}[t]
708	\centering
709	\caption{Deduplication statistics. The \texttt{exception\_only} format collapses multiple passing solutions into identical rows because correct executions produce no exception events. Train--test input overlap is 0 (no leakage).}
710	\label{tab:dedup}
711	\small
712	\begin{tabular}{lccc}
713	\toprule
714	\textbf{Split} & \textbf{Total} & \textbf{Unique} & \textbf{Dup.\ rate} \\
715	\midrule
716	exception\_only train & 4{,}720 & 2{,}858 & 39.45\% \\
717	exception\_only test  & 1{,}190 &   607 & 48.99\% \\
718	raw\_traces (full)    & 5{,}910 & 5{,}803 &  1.81\% \\
719	\bottomrule
720	\end{tabular}
721	\end{table}
722	
723	%% ============================================================
724	\section{Regex Baseline Analysis}
725	\label{sec:regex_baselines}
726	
727	To establish a non-learning upper bound, we evaluate six regex-based baselines on the \texttt{exception\_only} test set ($N{=}1{,}190$) and two format-specific baselines on VOTA and \texttt{full\_trace} inputs.
728	
729	\begin{table}[t]
730	\centering
731	\caption{Regex baseline accuracy ($N{=}1{,}190$). B4 is the strongest semantic baseline (6.22pp below SFT \texttt{exception\_only}, McNemar $p{<}.001$). B6 uses an error count threshold. $^\ddag$B5 exploits a data formatting artifact: the \texttt{[No exception data in trace]} marker is deterministically present in all pass samples, making this a format-level shortcut rather than a genuine exception-based heuristic.}
732	\label{tab:regex}
733	\small
734	\resizebox{\columnwidth}{!}{%
735	\begin{tabular}{llc}
736	\toprule
737	\textbf{Baseline} & \textbf{Method} & \textbf{Acc (\%)} \\
738	\midrule
739	B1: \texttt{[ERROR]} presence & string match & 93.45 \\
740	B2: Traceback presence & string match & 71.51 \\
741	B3: Any keyword & union of B1+B2+Exception & 93.45 \\
742	B4: Exception type regex & regex on exception class names & \textbf{93.61} \\
743	B5: Format marker & \texttt{[No exception data]} $\to$ pass & 99.33$^\ddag$ \\
744	B6: Error count $\geq$2 & count threshold & 92.02 \\
745	\midrule
746	VOTA format regex & best regex on VOTA traces & 75.55 \\
747	full\_trace format regex & best regex on full traces & 77.39 \\
748	\bottomrule
749	\end{tabular}%
750	}
751	\end{table}
752	
753	The strongest legitimate baseline (B4, 93.61\%) applies regex pattern-matching on Python exception class names (e.g., \texttt{ValueError}, \texttt{TypeError}).
754	Its errors concentrate on 8 boundary samples where a \texttt{ValueError} is raised inside a \texttt{try/except} block and caught; the program passes despite an exception occurring in the trace.
755	SFT \texttt{exception\_only} correctly classifies 6 of these 8 samples, indicating that the model learns the semantic distinction between caught (benign) and uncaught (fault-indicating) exceptions.
756	B5 (99.33\%) achieves near-SFT accuracy but relies on the deterministic presence of a format marker in pass-class traces, which is an artifact of the trace preprocessing pipeline rather than a generalizable signal; McNemar test vs.\ SFT yields $p{=}.041$, indicating a statistically significant difference.
757	
758	\paragraph{Cross-format comparison.}
759	Table~\ref{tab:regex_cross_format} compares SFT and the best applicable regex baseline for each trace format.
760	The SFT advantage increases with format complexity: \texttt{no\_trace} (+3.62pp over majority baseline) $<$ \texttt{full\_trace} (+4.37pp) $<$ \texttt{exception\_only} (+6.22pp) $\ll$ VOTA (+23.86pp).
761	The VOTA gap is largest because its structured multi-component format carries semantic content that regex cannot parse, while \texttt{exception\_only}'s simpler format allows regex to capture most of the signal.
762	
763	\begin{table}[t]
764	\centering
765	\caption{SFT vs.\ best regex baseline by trace format ($N{=}1{,}190$). Regex baselines: majority class for \texttt{no\_trace}, keyword matching for \texttt{full\_trace}, pattern matching for VOTA, exception type regex (B4) for \texttt{exception\_only}.}
766	\label{tab:regex_cross_format}
767	\small
768	\begin{tabular}{lccc}
769	\toprule
770	\textbf{Format} & \textbf{SFT (\%)} & \textbf{Regex (\%)} & \textbf{$\Delta$ (pp)} \\
771	\midrule
772	exception\_only & 99.83 & 93.61 & +6.22 \\
773	VOTA & 99.05 & 75.55 & +23.50 \\
774	full\_trace & 81.76 & 77.39 & +4.37 \\
775	no\_trace & 75.13 & 71.51 & +3.62 \\
776	\bottomrule
777	\end{tabular}
778	\end{table}
779	
780	%% ============================================================
781	\section{Cross-Model Zero-Shot Comparison}
782	\label{sec:zeroshot_cross_model}
783	
784	Table~\ref{tab:zeroshot_cross_model} compares zero-shot and SFT \texttt{exception\_only} accuracy across four models.
785	Zero-shot performance does not correlate with model size: the smallest model (Qwen-1.5B, 93.45\%) outperforms all larger models, while the largest (CodeLlama-13B) falls below majority baseline.
786	SFT compresses the 42.44pp zero-shot range to 0.50pp, eliminating architecture-dependent variance.
787	
788	\begin{table}[t]
789	\centering
790	\caption{Zero-shot vs.\ SFT \texttt{exception\_only} across four models ($N{=}1{,}190$). Zero-shot accuracy is uncorrelated with model size; SFT normalizes cross-architecture variance from 42.44pp to 0.50pp.}
791	\label{tab:zeroshot_cross_model}
792	\small
793	\resizebox{\columnwidth}{!}{%
794	\begin{tabular}{llccc}
795	\toprule
796	\textbf{Model} & \textbf{Size} & \textbf{Zero-shot (\%)} & \textbf{SFT (\%)} & \textbf{$\Delta$ (pp)} \\
797	\midrule
798	Qwen-1.5B & 1.5B & 93.45 & 99.83 & +6.38 \\
799	DeepSeek-6.7B & 6.7B & 90.59 & 99.39 & +8.80 \\
800	Qwen-7B & 7B & 89.08 & 99.83 & +10.75 \\
801	CodeLlama-13B & 13B & 51.01 & 99.89 & +48.88 \\
802	\midrule
803	Range & --- & 42.44pp & 0.50pp & --- \\
804	\bottomrule
805	\end{tabular}%
806	}
807	\end{table}
808	
809	\subsection{Calibration Analysis}
810	\label{sec:calibration_analysis}
811	
812	\begin{table}[h]
813	\centering
814	\caption{Model calibration on \texttt{exception\_only} (seed 42). All four models achieve ECE $<$ 0.005, indicating that near-perfect accuracy reflects genuine confidence rather than overfit predictions.}
815	\label{tab:calibration_model_level}
816	\small
817	\resizebox{\columnwidth}{!}{%
818	\begin{tabular}{lcccc}
819	\toprule
820	\textbf{Model} & \textbf{Accuracy} & \textbf{ECE $\downarrow$} & \textbf{Brier $\downarrow$} & \textbf{Mean Conf.} \\
821	\midrule
822	Qwen-2.5-1.5B & 99.83\% & 0.0014 & 0.0013 & 99.82\% \\
823	Qwen-2.5-7B & 99.83\% & 0.0017 & 0.0013 & 99.80\% \\
824	CodeLlama-13B & 99.83\% & 0.0020 & 0.0013 & 99.63\% \\
825	DeepSeek-6.7B & 99.33\% & 0.0048 & 0.0059 & 99.71\% \\
826	\bottomrule
827	\end{tabular}%
828	}
829	\end{table}
830	
831	%% ============================================================
832	\section{Use of AI Assistants}
833	\label{app:ai-assistants}
834	
835	We used Claude (Anthropic) as an AI coding and writing assistant
836	throughout this work. Specifically:
837	\begin{itemize}
838	    \item \textbf{Code:} drafting experiment scripts, data-processing
839	    pipelines, and analysis utilities; debugging and refactoring.
840	    \item \textbf{Writing:} drafting and revising paper sections,
841	    polishing prose, and reformatting LaTeX.
842	    \item \textbf{Literature:} summarizing related papers to inform
843	    the related-work section.
844	\end{itemize}
845	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "63cc777d-ae6a-4f80-831d-908447a8afda",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/appendix.tex",
      "content": "\\section{Per-Class Performance Breakdown}\n\\label{sec:per_class}\n\nTable~\\ref{tab:per_class} reports per-class precision, recall, and F1 for all experimental conditions.\n\n\\begin{table*}[t]\n\\centering\n\\caption{Per-class precision, recall, and F1 for all experimental conditions (seed 42). DeepSeek VOTA seed 42 is a training failure (84.45\\%, fail recall = 45.4\\%) due to tokenizer-driven truncation; seeds 123/456 achieve 99.16\\%/99.33\\%.}\n\\label{tab:per_class}\n\\small\n\\begin{tabular}{llccccccc}\n\\toprule\n\\textbf{Condition} & \\textbf{Model} & \\textbf{Acc} & \\textbf{Pass P} & \\textbf{Pass R} & \\textbf{Pass F1} & \\textbf{Fail P} & \\textbf{Fail R} & \\textbf{Fail F1} \\\\\n\\midrule\nNo Trace          & Qwen-2.5-7B & 75.13 & 87.76 & 75.79 & 81.34 & 54.73 & 73.45 & 62.72 \\\\\nFull Trace        & Qwen-2.5-7B & 81.76 & 87.74 & 86.60 & 87.17 & 67.43 & 69.62 & 68.51 \\\\\nFull Trace (LO)   & Qwen-2.5-7B & 85.94 & 88.21 & 93.18 & 90.63 & 80.07 & 68.73 & 73.97 \\\\\nVOTA              & Qwen-2.5-7B & 99.05 & 100.00 & 99.18 & 99.59 & 97.98 & 100.00 & 98.98 \\\\\nException Only    & Qwen-2.5-7B & 99.83 & 100.00 & 99.76 & 99.88 & 99.41 & 100.00 & 99.71 \\\\\nAE Only           & Qwen-2.5-7B & 99.92 & 100.00 & 99.88 & 99.94 & 99.71 & 100.00 & 99.85 \\\\\nLoop Only         & Qwen-2.5-7B & 86.05 & 92.39 & 87.07 & 89.66 & 71.65 & 82.01 & 76.48 \\\\\nVOTA\\_no\\_ae       & Qwen-2.5-7B & 99.41 & 99.88 & 99.29 & 99.59 & 98.26 & 99.71 & 98.98 \\\\\n\\midrule\nNo Trace          & DeepSeek-6.7B & 73.36 & 81.71 & 80.85 & 81.28 & 53.16 & 54.57 & 53.86 \\\\\nFull Trace        & DeepSeek-6.7B & 79.16 & 85.70 & 85.10 & 85.40 & 63.20 & 64.30 & 63.70 \\\\\nVOTA              & DeepSeek-6.7B & 84.45 & 82.14 & 100.00 & 90.20 & 100.00 & 45.40 & 62.50 \\\\\nException Only    & DeepSeek-6.7B & 99.33 & 100.00 & 99.06 & 99.53 & 97.69 & 100.00 & 98.83 \\\\\nAE Only           & DeepSeek-6.7B & 98.74 & 98.40 & 99.90 & 99.10 & 99.70 & 95.90 & 97.70 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n%% ============================================================\n\\section{Training Details}\n\\label{sec:training_details}\n\nTable~\\ref{tab:hyperparams} summarizes the training hyperparameters shared across all conditions.\nAll experiments use the HuggingFace TRL \\texttt{SFTTrainer} with LoRA \\citep{hu2022lora} applied to all linear layers.\n\n\\begin{table}[t]\n\\centering\n\\caption{Training hyperparameters (shared across all conditions).}\n\\label{tab:hyperparams}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{ll}\n\\toprule\n\\textbf{Hyperparameter} & \\textbf{Value} \\\\\n\\midrule\nLoRA rank ($r$)            & 16 \\\\\nLoRA alpha ($\\alpha$)      & 32 \\\\\nLoRA dropout               & 0.05 \\\\\nLoRA target modules        & all linear layers \\\\\n\\midrule\nEpochs                     & 3 \\\\\nPer-device batch size       & 4 \\\\\nGradient accumulation steps & 8 \\\\\nEffective batch size        & 32 \\\\\n\\midrule\nLearning rate               & $2 \\times 10^{-4}$ \\\\\nLR scheduler                & linear decay \\\\\nWarmup ratio                & 0.1 \\\\\nWeight decay                & 0.01 \\\\\n\\midrule\nMax sequence length         & 2048 tokens \\\\\nPrimary seed                & 42 \\\\\nRobustness seeds            & 123, 456 \\\\\n\\midrule\nHardware                    & 1$\\times$ enterprise-grade GPU (${\\geq}$80\\,GB VRAM) \\\\\nFramework                   & HuggingFace TRL SFTTrainer \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\nTable~\\ref{tab:train_time} reports per-condition training wall-clock times.\nConditions with longer trace inputs (e.g., \\texttt{full\\_trace}, VOTA) require proportionally more training time due to increased sequence lengths.\n\n\\begin{table}[t]\n\\centering\n\\caption{Training wall-clock time per condition on a single enterprise-grade GPU (${\\geq}$80\\,GB VRAM). Where multiple seeds were run, individual times are listed.}\n\\label{tab:train_time}\n\\small\n\\begin{tabular}{llr}\n\\toprule\n\\textbf{Condition} & \\textbf{Seed(s)} & \\textbf{Time (h)} \\\\\n\\midrule\nno\\_trace       & 42         & ${\\sim}$0.5 \\\\\nfull\\_trace     & 42         & ${\\sim}$2.2 \\\\\nlabel\\_only     & 42         & ${\\sim}$2.2 \\\\\nVOTA                     & 42         & ${\\sim}$2.3 \\\\\nexception\\_only & 42         & ${\\sim}$2.1 \\\\\nexception\\_only & 123        & ${\\sim}$2.1 \\\\\nexception\\_only & 456        & ${\\sim}$1.3 \\\\\nae\\_only        & 42         & ${\\sim}$1.8 \\\\\nloop\\_only      & 42         & ${\\sim}$2.1 \\\\\nVOTA\\_no\\_ae    & 42         & ${\\sim}$1.8 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n%% ============================================================\n\\section{VOTA Extraction Algorithm}\n\\label{sec:vota_algorithm}\n\nAlgorithm~\\ref{alg:vota} describes the three-component VOTA extraction pipeline applied to a raw \\texttt{sys.settrace} execution log.\n\n\\begin{algorithm}[t]\n\\caption{VOTA Trace Extraction}\n\\label{alg:vota}\n\\small\n\\begin{algorithmic}[1]\n\\REQUIRE Raw trace $T$ from \\texttt{sys.settrace} (list of events)\n\\ENSURE Compressed VOTA representation $V$\n\\STATE $V \\leftarrow$ empty string\n\\STATE \\textbf{// Component 1: Exception summary}\n\\FOR{each event $e$ in $T$ with type \\texttt{exception}}\n  \\STATE Parse traceback $\\rightarrow$ extract error type, message, file, line\n  \\STATE Append \\texttt{[ERROR] type: message (file:line)} to $V$\n\\ENDFOR\n\\IF{no exception events found}\n  \\STATE Append \\texttt{[No exception data in trace]} to $V$\n\\ENDIF\n\\STATE \\textbf{// Component 2: Assertion-point comparison}\n\\FOR{each \\texttt{assert} or \\texttt{return} event $e$ in $T$}\n  \\STATE Extract actual value from execution state\n  \\STATE Extract expected value from test assertion\n  \\STATE Append \\texttt{[ASSERT] actual=... expected=... match=T/F} to $V$\n\\ENDFOR\n\\STATE \\textbf{// Component 3: Loop compression}\n\\FOR{each consecutive repeated line sequence $S$ in $T$}\n  \\IF{$|S| \\geq 2$ iterations of same loop body}\n    \\STATE Replace $S$ with single iteration + \\texttt{[repeated $\\times$N]}\n  \\ENDIF\n\\ENDFOR\n\\STATE Append compressed non-exception lines to $V$\n\\RETURN $V$\n\\end{algorithmic}\n\\end{algorithm}\n\n%% ============================================================\n\\section{VOTA Trace Examples}\n\\label{sec:vota_examples}\n\nWe provide two representative VOTA trace examples illustrating the fail and pass cases.\nIn the fail case, the exception event provides an unambiguous fault signal.\nIn the pass case, the absence of an exception event combined with a matching assertion point confirms correct execution.\n\n\\paragraph{Fail example.}\nA \\texttt{ZeroDivisionError} triggers an \\texttt{[ERROR]} event, providing a direct fault signal that is sufficient for the model to predict \\texttt{fail}.\n\n\\begin{scriptsize}\n\\begin{verbatim}\n## Function\ndef divide(a, b):\n    return a / b\n\n## Test Input\ndivide(1, 0)\n\n## Expected Output\ninf\n\n## VOTA Trace\n[ERROR] ZeroDivisionError: division by zero\n\n## Verdict\nfail\n\\end{verbatim}\n\\end{scriptsize}\n\n\\paragraph{Pass example.}\nNo exception is raised, and the assertion point confirms that the actual output matches the expected value.\n\n\\begin{scriptsize}\n\\begin{verbatim}\n## Function\ndef add(a, b):\n    return a + b\n\n## Test Input\nadd(2, 3)\n\n## Expected Output\n5\n\n## VOTA Trace\n[LOOP] No loops detected.\n[ASSERT] actual=5, expected=5\n\n## Verdict\npass\n\\end{verbatim}\n\\end{scriptsize}\n\nThese examples illustrate the core asymmetry exploited by the \\texttt{exception\\_only} condition: fail cases produce an explicit \\texttt{[ERROR]} event, while pass cases are characterized by its absence.\nThis binary signal (presence vs.\\ absence of an exception) is sufficient for near-perfect verdict prediction.\n\n%% ============================================================\n\\section{Full Experimental Results}\n\\label{sec:full_results}\n\nTables~\\ref{tab:full_qwen} and \\ref{tab:full_deepseek} report the complete experimental results across all conditions, models, and seeds.\n\n\\begin{table}[t]\n\\centering\n\\caption{Full results for Qwen-2.5-Coder-7B across all conditions and seeds. Conditions with a single seed report no variance. \\texttt{exception\\_only} achieves 99.83\\% across all three seeds ($\\sigma{=}$0). \\texttt{ae\\_only} achieves 99.64\\% mean ($\\pm$0.49; seed 123 at 99.08\\% is the outlier).}\n\\label{tab:full_qwen}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Condition} & \\textbf{S42} & \\textbf{S123} & \\textbf{S456} & \\textbf{Mean $\\pm$ Std} \\\\\n\\midrule\nexception\\_only & 99.83 & 99.83 & 99.83 & 99.83 $\\pm$ 0.00 \\\\\nae\\_only        & 99.92 & 99.08 & 99.92 & 99.64 $\\pm$ 0.49 \\\\\nVOTA                     & 99.41 & 98.66 & 99.08 & 99.05 $\\pm$ 0.38 \\\\\nVOTA\\_no\\_ae    & 99.41 & ---   & ---   & --- \\\\\nlabel\\_only     & 86.22 & 86.89 & 84.70 & 85.94 $\\pm$ 1.12 \\\\\nloop\\_only      & 85.63 & 85.88 & 86.64 & 86.05 $\\pm$ 0.52 \\\\\nfull\\_trace     & 81.76 & 80.20 & 82.35 & 81.44 $\\pm$ 1.11 \\\\\nno\\_trace       & 75.13 & ---   & ---   & --- \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\\begin{table}[t]\n\\centering\n\\caption{Full results for DeepSeek-Coder-6.7B across all conditions and seeds. \\texttt{exception\\_only} is consistent across seeds: 99.33/99.50/99.33 ($\\sigma{=}$0.10pp).}\n\\label{tab:full_deepseek}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Condition} & \\textbf{Seed} & \\textbf{Accuracy} & \\textbf{Notes} \\\\\n\\midrule\nexception\\_only & 42  & 99.33 & epoch 1: 99.83 \\\\\nexception\\_only & 456 & 99.33 & CI [98.82, 99.75] \\\\\nexception\\_only & 123 & 99.50 & \\\\\n\\midrule\nVOTA                     & 42  & 84.45 & training failure; fail recall = 45.4\\% \\\\\nVOTA                     & 123 & 99.16 & \\\\\nVOTA                     & 456 & 99.33 & \\\\\nno\\_trace       & 42  & 73.36 & \\\\\nfull\\_trace     & 42  & 79.16 & CI [76.80, 81.30] \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n%% ============================================================\n\\section{Tokenizer and Truncation Analysis}\n\\label{sec:tokenizer_analysis}\n\nDeepSeek VOTA seed 42 (84.45\\%) is a training failure driven by tokenizer-induced truncation.\nRe-evaluation of the seed 42 checkpoint with the standard max\\_length=2048 yields 16\\% accuracy, consistent with complete model collapse rather than marginal degradation.\nThe previously reported 84.45\\% was obtained with max\\_length=16384, which partially bypasses tokenizer truncation.\nSeeds 123 and 456, evaluated under identical conditions, achieve 99.16\\% and 99.33\\% respectively.\nThe DeepSeek tokenizer averages 2{,}626 tokens per VOTA sample versus 1{,}929 for Qwen, causing 91.7\\% of DeepSeek VOTA training samples to exceed the 2{,}048-token context window.\nThe training framework preserves the verdict label but truncates trace content, so the model trains with incomplete diagnostic information for the majority of samples.\nSeeds 123 and 456 (99.16\\% and 99.33\\%) demonstrate that DeepSeek can learn VOTA when LoRA initialization avoids the truncation-sensitive basin; the 2-seed mean (99.25\\%$\\pm$0.12) matches the cross-model VOTA range (98.74--99.54\\%).\n\nA post-hoc group analysis on seed 42 provides directional evidence: partitioning test samples by whether their training-set counterparts exceeded the context window, intact samples ($N{=}99$) achieve 100\\% accuracy while truncated samples ($N{=}1{,}091$) achieve 83.04\\% (95\\% CI [80.75\\%, 85.24\\%]; Fisher exact $p{<}.001$), with all 185 errors concentrated in the fail class (fail recall = 31.23\\%).\nPer-class analysis (Table~\\ref{tab:per_class}) shows that seed 42 achieves 100\\% fail precision but only 45.43\\% fail recall, systematically defaulting to \\texttt{pass}.\n\nSeed robustness is consistent across models: Qwen \\texttt{exception\\_only} produces identical 99.83\\% across all three seeds ($\\sigma{=}0$), and DeepSeek achieves 99.39\\%$\\pm$0.10 (seeds 42/456: 99.33\\%, seed 123: 99.50\\%).\nBecause \\texttt{exception\\_only} test inputs contain 48.99\\% duplicates (607 unique of 1,190; \\S\\ref{sec:dataset}), CIs assume $n{=}1{,}190$ independent trials; under deduplication ($n{=}607$), Qwen's accuracy is 99.67\\% (Wilson CI [98.81, 99.91]).\n\n%% ============================================================\n\\section{Persistent Error Analysis}\n\\label{sec:irreducible}\n\nThe \\texttt{exception\\_only} condition with Qwen-2.5-Coder-7B misclassifies exactly 2 out of 1,190 test samples across all three seeds (42, 123, 456), with 100\\% overlap across seeds.\nBoth samples (IDs 901 and 905) share the following characteristics:\n\n\\begin{itemize}\n\\item \\textbf{Function:} \\texttt{check\\_dict\\_case} (HumanEval/95), a function that checks whether all dictionary keys are uniformly upper-case or lower-case strings.\n\\item \\textbf{Ground-truth label:} \\texttt{pass}.\n\\item \\textbf{Predicted label:} \\texttt{fail} (false negative).\n\\item \\textbf{Cross-seed consistency:} Both samples are misclassified identically by all three seeds, indicating a systematic rather than stochastic error.\n\\end{itemize}\n\nManual inspection reveals the root cause: \\texttt{check\\_dict\\_case} uses \\texttt{all()} over a generator expression, and Python's \\texttt{all()} short-circuits on the first \\texttt{True} value, raising \\texttt{GeneratorExit} to terminate the generator.\nBecause \\texttt{GeneratorExit} is a \\texttt{BaseException} subclass, the tracer records it as seven \\texttt{[ERROR] GeneratorExit} lines, even though the function executes correctly and the test passes.\nThe model observes these spurious error markers and reasonably but incorrectly predicts \\texttt{fail}.\nThis is not a model failure but a representation ambiguity: the \\texttt{exception\\_only} format cannot distinguish genuine exceptions from benign \\texttt{BaseException} subclasses triggered by Python's iterator protocol.\n\nMost configurations converge to these same 2 errors: Qwen-1.5B, Qwen-7B (3 seeds), CodeLlama-13B (seeds 42/456), and DeepSeek-6.7B (seeds 42/456) all produce error set $\\{901, 905\\}$.\nHowever, CodeLlama-13B seed 123 achieves 100\\% accuracy (0/1190 errors), correctly classifying both samples.\nThis demonstrates that 99.83\\% is a near-perfect \\emph{floor} (the convergence attractor for most LoRA initializations) rather than a hard data ceiling: the representation supports perfect accuracy, but most initializations converge to the same 2-error basin.\nThe practical implication is that these errors are high-probability convergence artifacts addressable through seed selection or ensemble methods, not fundamental limitations of the exception-based representation.\n\n%% ============================================================\n\\section{Exception Type Accuracy Breakdown}\n\\label{sec:exception_type}\n\nTable~\\ref{tab:exception_type} reports \\texttt{exception\\_only} accuracy stratified by exception type on Qwen-2.5-7B (seed=42, $N{=}1{,}190$).\nAll standard exception types (\\texttt{TypeError}, \\texttt{ValueError}, \\texttt{IndexError}, etc.) achieve 100\\% accuracy.\nThe only misclassifications arise from \\texttt{GeneratorExit}, a \\texttt{BaseException} subclass that is not an \\texttt{Exception}. It is raised by Python's iterator protocol during generator short-circuiting, not by actual program errors.\n\n\\begin{table}[t]\n\\centering\n\\caption{Exception type accuracy breakdown for \\texttt{exception\\_only} (Qwen-7B, seed=42). All true error types achieve 100\\%. The only failures come from \\texttt{GeneratorExit} (a \\texttt{BaseException} subclass, not an \\texttt{Exception}), which appears in 2 passing samples.}\n\\label{tab:exception_type}\n\\small\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Exception Type} & \\textbf{Samples} & \\textbf{Accuracy} \\\\\n\\midrule\nTypeError & 96 & 100\\% \\\\\nValueError & 62 & 100\\% \\\\\nIndexError & 41 & 100\\% \\\\\nKeyError & 28 & 100\\% \\\\\nAttributeError & 19 & 100\\% \\\\\nAssertionError & 15 & 100\\% \\\\\nRecursionError & 12 & 100\\% \\\\\nOther Exception & 66 & 100\\% \\\\\n\\midrule\nGeneratorExit (BaseException) & 2 & 0\\% \\\\\nNo exception (pass class) & 849 & 100\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThis is consistent with the model having learned a clean decision boundary: any true \\texttt{Exception} subclass in the trace implies failure.\nThe \\texttt{GeneratorExit} case represents a semantic ambiguity in the trace format rather than a model failure, as discussed in \\S\\ref{sec:irreducible}.\n\n%% ============================================================\n\\section{Exception Subcomponent Ablation}\n\\label{sec:exc_subcomponent}\n\nTo test whether verdict prediction depends on a specific exception subcomponent or merely the binary presence of an exception event, we train Qwen-2.5-7B on three subcomponent-only conditions (seed 42, $N{=}1{,}190$).\n\n\\begin{table}[t]\n\\centering\n\\caption{Exception subcomponent ablation (Qwen-2.5-7B, seed 42, $N{=}1{,}190$). All three subcomponents independently achieve ${\\geq}$99.50\\%. $^\\dag$Retains \\texttt{[ERROR]} format marker; $^\\ddag$no format markers, bare exception class name only.}\n\\label{tab:exc_subcomponent}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Condition} & \\textbf{Acc (\\%)} & \\textbf{Fail R} & \\textbf{Pass R} \\\\\n\\midrule\nexc\\_type\\_only$^\\dag$ & \\textbf{100.00} & 100.00 & 100.00 \\\\\nexc\\_stacktrace\\_only$^\\dag$ & 99.83 & 100.00 & 99.76 \\\\\nexc\\_message\\_only$^\\ddag$ & 99.50 & 100.00 & 99.29 \\\\\n\\midrule\nexception\\_only (ref.) & 99.83 & 100.00 & 99.76 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll three subcomponents independently achieve ${\\geq}$99.50\\% with 100\\% fail recall (Table~\\ref{tab:exc_subcomponent}), showing that no single subcomponent is necessary for Tier~1 performance.\n\n\\paragraph{Format marker confound.}\n\\texttt{exc\\_type\\_only} and \\texttt{exc\\_stacktrace\\_only} retain the \\texttt{[ERROR]} prefix marker present in the full \\texttt{exception\\_only} format; \\texttt{exc\\_message\\_only} contains only the bare exception class name and message text without any format markers.\nBecause the marker alone is sufficient for near-perfect regex accuracy (B5: 99.33\\%; \\S\\ref{sec:nomarker}), \\texttt{exc\\_type\\_only} (100.00\\%) and \\texttt{exc\\_stacktrace\\_only} (99.83\\%) are confounded with marker-based classification; we therefore do not make hierarchy claims among subcomponents.\n\\texttt{exc\\_message\\_only} (99.50\\%) provides a clean test: without any format markers, it achieves accuracy comparable to the full \\texttt{exception\\_only} condition (99.83\\%), complementing the dedicated marker-removal ablation (\\texttt{nomarker}: 97.65\\%; \\S\\ref{sec:nomarker}) as additional evidence that the model learns semantic exception patterns rather than format shortcuts.\n\n%% ============================================================\n\\section{Trace Length Ablation}\n\\label{sec:trace_length_full}\n\nTo test whether the \\texttt{full\\_trace} performance gap is caused by input truncation at training time, we vary the maximum trace token budget on Qwen-2.5-7B (seed=42) while keeping all other hyperparameters fixed.\n\n\\begin{table}[t]\n\\centering\n\\caption{Trace length and truncation direction ablation on Qwen-2.5-7B ($N{=}1{,}190$, seed=42). Head = standard left-truncation (retain first $k$ tokens); Tail = retain last $k$ tokens. Per-condition bootstrap 95\\% CIs ($B{=}10{,}000$).}\n\\label{tab:trace_length}\n\\small\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Direction} & \\textbf{Max Tokens} & \\textbf{Acc (\\%)} & \\textbf{95\\% CI} \\\\\n\\midrule\nHead & 256  & 78.82 & [76.4, 81.0] \\\\\nHead & 512  & 80.42 & [78.2, 82.6] \\\\\nHead & 1024 & 77.23 & [74.9, 79.6] \\\\\nHead & no\\_limit ($\\infty$) & 81.76 & [79.7, 83.9] \\\\\n\\midrule\nTail & 256  & 77.48 & --- \\\\\nTail & 512  & 93.61 & --- \\\\\nTail & 1024 & 96.47 & --- \\\\\nTail & 2048 & 97.31 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n% Budget curve figure moved to main text (Figure~\\ref{fig:budget_curve}).\n\nAs shown in Table~\\ref{tab:trace_length} and Figure~\\ref{fig:budget_curve}, all four trace length conditions fall within a 5pp range (77.2\\%--81.8\\%).\nTo quantify the reliability of the observed differences, Table~\\ref{tab:trace_length_pairwise} reports paired bootstrap comparisons ($B{=}10{,}000$, seed=42) across all condition pairs.\n\n\\begin{table}[t]\n\\centering\n\\caption{Pairwise paired bootstrap comparisons for trace length ablation ($B{=}10{,}000$, seed=42). $\\Delta$ = accuracy difference between the two conditions (first $-$ second in the budget group; condition $-$ baseline in the other groups). **$p{<}.01$; ***$p{<}.001$.}\n\\label{tab:trace_length_pairwise}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llccc}\n\\toprule\n& \\textbf{Comparison} & \\textbf{$\\Delta$ (pp)} & \\textbf{95\\% CI} & \\textbf{$p$-value} \\\\\n\\midrule\n\\multirow{4}{*}{\\rotatebox{90}{\\scriptsize Budget}}\n& 512 vs.\\ 256           & $+$1.60  & [$-$0.34, $+$3.53]   & 0.117 \\\\\n& 1024 vs.\\ 512          & $-$3.19  & [$-$5.29, $-$1.09]   & 0.002** \\\\\n& no\\_limit vs.\\ 1024    & $+$4.54  & [$+$2.52, $+$6.55]   & ${<}$0.001*** \\\\\n& no\\_limit vs.\\ 256     & $+$2.94  & [$+$0.84, $+$5.04]   & 0.006** \\\\\n\\midrule\n\\multirow{4}{*}{\\rotatebox{90}{\\scriptsize vs.\\ no\\_trace}}\n& 256 $-$ no\\_trace       & $+$3.70  & [$+$1.43, $+$6.05]   & 0.002** \\\\\n& 512 $-$ no\\_trace       & $+$5.29  & [$+$3.03, $+$7.56]   & ${<}$0.001*** \\\\\n& 1024 $-$ no\\_trace      & $+$2.10  & [$-$0.17, $+$4.37]   & 0.078 \\\\\n& no\\_limit $-$ no\\_trace & $+$6.64  & [$+$4.37, $+$8.99]   & ${<}$0.001*** \\\\\n\\midrule\n\\multirow{4}{*}{\\rotatebox{90}{\\scriptsize vs.\\ exc.}}\n& 256 $-$ exc\\_only       & $-$21.01 & [$-$23.45, $-$18.74] & ${<}$0.001*** \\\\\n& 512 $-$ exc\\_only       & $-$19.41 & [$-$21.76, $-$17.14] & ${<}$0.001*** \\\\\n& 1024 $-$ exc\\_only      & $-$22.61 & [$-$25.04, $-$20.25] & ${<}$0.001*** \\\\\n& no\\_limit $-$ exc\\_only & $-$18.07 & [$-$20.34, $-$15.88] & ${<}$0.001*** \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\\paragraph{Non-monotonic pattern (head-truncation).}\nUnder head-truncation (retaining trace prefixes), the trend is non-monotonic: 512 tokens (80.42\\%) slightly outperforms 256 tokens (78.82\\%), but doubling to 1024 tokens \\emph{decreases} accuracy to 77.23\\%, a statistically significant 3.19pp drop ($p{=}.002$, 95\\% CI [$-$5.29, $-$1.09]).\nThe no-limit condition (81.76\\%) recovers and significantly exceeds 1024 tokens ($p{<}.001$), but 1024 tokens is not significantly better than \\texttt{no\\_trace} (75.13\\%; $\\Delta{=}{+}2.10$pp, $p{=}.078$, 95\\% CI [$-$0.17, $+$4.37]).\nThis non-monotonicity is specific to head-truncation: the 1024-token prefix retains enough irrelevant content to mislead the model while discarding diagnostic events that appear near the trace terminus.\nUnder tail-truncation, accuracy increases monotonically for Qwen-7B and Qwen-1.5B (Table~\\ref{tab:tail_cross_model}); only DeepSeek-6.7B shows a mild $-$1.5pp decrease at tail-1024$\\to$tail-2048, attributable to architecture-specific long-context sensitivity rather than a systematic mid-length pathology.\n\n\\paragraph{Comparison to baselines.}\nAll four trace budget conditions significantly exceed \\texttt{no\\_trace} except 1024 tokens ($p{=}.078$), indicating that raw trace content provides some signal but unreliably so.\nThe gap to \\texttt{exception\\_only} (99.83\\%) is massive for every budget condition (18--23pp, all $p{<}.001$), underscoring that even unlimited raw traces cannot substitute for targeted signal extraction.\nThe best full-trace condition (no\\_limit, 81.76\\%) still lags \\texttt{exception\\_only} by 18.07pp (95\\% CI [$-$20.34, $-$15.88]).\n\n\\paragraph{Interpretation.}\nThese results rule out input truncation as the primary explanation for the full-trace performance gap: even with unlimited tokens, the model cannot extract the diagnostic signal that VOTA's targeted compression provides.\nThe non-monotonic dip at 1024 tokens is consistent with a ``worst-of-both-worlds'' regime where the model receives enough noisy context to dilute the signal but not enough to compensate through broader coverage.\nThe result reinforces the information density interpretation (\\S\\ref{sec:density}): the gap between full traces and VOTA is driven by the \\emph{content} of the trace (irrelevant lines diluting the diagnostic signal), not its \\emph{length}.\nIn contrast, VOTA's compressed representation concentrates the diagnostic signal into fewer tokens, making it sensitive to truncation when those tokens are removed (\\S\\ref{sec:cross_model}).\n\n\\paragraph{Truncation direction.}\nTail-truncation (retaining the last $k$ tokens) dramatically outperforms head-truncation: \\texttt{tail\\_2048} achieves 97.31\\% vs.\\ \\texttt{head\\_2048} (no\\_limit) at 81.76\\%, a 15.55pp improvement.\nEven \\texttt{tail\\_512} (93.61\\%) exceeds every head-truncation condition by over 11pp.\n\nHowever, \\texttt{tail\\_256} (77.48\\%) performs at the \\texttt{no\\_trace} baseline level (75.13\\%), indicating that the diagnostic signal does not reside in the very last trace lines.\nThe critical jump occurs between 256 and 512 tail tokens (+16.13pp), localizing the signal window to approximately 256--512 tokens from the trace terminus.\nThis is consistent with the trace format: the globals module dump consumes the first ${\\sim}$384 tail tokens (pure noise), so structured execution markers (\\texttt{[Line~X]} variable values) only become visible when the budget exceeds this threshold.\n\nThe 18.07pp gap from \\texttt{full\\_trace} to \\texttt{exception\\_only} decomposes as: 86\\% positional concentration (recovered by tail-truncation at 2048 tokens) and 14\\% residual content noise (the 2.52pp gap from \\texttt{tail\\_2048} to \\texttt{exception\\_only} that persists regardless of truncation direction).\nThe fact that \\texttt{exception\\_only} (99.83\\%) still outperforms \\texttt{tail\\_2048} (97.31\\%) indicates that semantic extraction (identifying the exception type and message) is superior to positional extraction (keeping a fixed window), because the model need not filter out non-diagnostic lines that happen to fall within the window.\n\n\\paragraph{Cross-model budget curve.}\nTable~\\ref{tab:tail_cross_model} extends the tail-truncation analysis to a full budget sweep across four models spanning three architecture families and an 8.7$\\times$ parameter range.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-model tail-truncation budget curve ($N{=}1{,}190$). All four models exhibit a transition between tail-384 and tail-512 (+11--22pp). $\\downarrow$: non-monotonic decrease. $^\\dag$CodeLlama tail-384/512/1024 trained with label-only loss to address tokenizer-driven gradient dilution (\\S\\ref{sec:tokenizer_analysis}); tail-1024 reports best-epoch accuracy (epoch 1). CodeLlama tail entries are not directly comparable to other models (which use full-sequence loss). $^\\ddag$CodeLlama tail-2048 outlier (41.8\\%): LoRA long-sequence instability under label-only loss; excluded from cross-model analysis.}\n\\label{tab:tail_cross_model}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccccc}\n\\toprule\n\\textbf{Model} & \\textbf{tail-256} & \\textbf{tail-384} & \\textbf{tail-512} & \\textbf{tail-1024} & \\textbf{tail-2048} & \\textbf{exc\\_only} \\\\\n\\midrule\nQwen-7B (7B) & 78.9 & 79.9 & 93.6 & 96.5 & 97.3 & 99.83 \\\\\nDeepSeek (6.7B) & 76.4 & 80.7 & 93.9 & 96.5 & 95.0$\\downarrow$ & 99.33 \\\\\nCodeLlama (13B) & 77.9 & 82.7$^\\dag$ & 98.2$^\\dag$ & 98.2$^\\dag$ & 41.8$^\\ddag$ & 99.89 \\\\\nQwen-1.5B (1.5B) & 72.6 & 73.6 & 95.6 & 96.6 & 97.9 & 99.83 \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-model truncation direction comparison ($N{=}1{,}190$). Head-truncation retains the first 2,048 tokens; tail-truncation retains the last 2,048. All four models' head-2048 accuracies converge into a narrow 75.3--81.8\\% band (6.5pp), comparable to the tail-256 signal-poor band (72.6--78.9\\%, 6.3pp). $^\\dag$CodeLlama tail-2048 pending retraining (\\S\\ref{sec:tokenizer_analysis}).}\n\\label{tab:head_vs_tail}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Model} & \\textbf{head-2048 (\\%)} & \\textbf{tail-2048 (\\%)} & \\textbf{Gap (pp)} \\\\\n\\midrule\nQwen-1.5B & 75.3 & 97.9 & +22.6 \\\\\nDeepSeek-6.7B & 78.7 & 95.0 & +16.3 \\\\\nCodeLlama-13B & 79.9 & ---$^\\dag$ & ---$^\\dag$ \\\\\nQwen-7B & 81.8 & 97.3 & +15.5 \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\nFour patterns emerge from the budget curve.\n\\emph{Phase transition between 384 and 512 tokens}: the tail-384 column reveals that the transition is not instantaneous at 256$\\to$512 but localized between 384 and 512 tokens.\nAt tail-384, all four models remain near baseline (73.6--80.7\\%), gaining only +1.0--4.8pp over tail-256.\nThe steep jump occurs at 384$\\to$512: +13.7pp (Qwen-7B), +13.2pp (DeepSeek), +15.5pp (CodeLlama), +22.0pp (Qwen-1.5B), crossing from near-baseline to near-ceiling.\nThis localizes the critical threshold to ${\\sim}$400--500 tokens: below ${\\sim}$384 tokens, the entire token budget is consumed by globals module dumps (pure noise); above ${\\sim}$512, at least one \\texttt{[Line~X]} execution event marker becomes visible, regardless of model capacity or architecture.\n\n\\emph{Convergence at tail-512+}: once the sharp performance jump is crossed, accuracy converges across all models into a 93.6--98.2\\% band at tail-512 (seed 42).\nMulti-seed validation shows robustness: across all 12 model$\\times$seed combinations at tail-512 (Table~\\ref{tab:tail512_seeds}), all accuracies fall within [93.61\\%, 98.24\\%], a 4.63pp band that compresses the signal-poor tail-256 spread (6.3pp) by 27\\%.\nCodeLlama-13B shows perfect per-model convergence at tail-512: all three seeds achieve 98.24\\% ($\\sigma{=}$0), consistent with the 13B scale and label-only loss providing a stronger optimization signal in the signal-rich regime (Table~\\ref{tab:tail512_seeds}).\nHowever, CodeLlama's higher tail-512 accuracy may partly reflect label-only loss rather than model capacity; direct comparison with other models (which use full-sequence loss) is confounded by this training difference.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-seed convergence at the tail-512 truncation point ($N{=}1{,}190$ per seed). All 12 model$\\times$seed combinations fall within a 4.63pp band [93.61\\%, 98.24\\%]. CodeLlama-13B achieves identical accuracy across all three seeds ($\\sigma{=}$0).}\n\\label{tab:tail512_seeds}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccr}\n\\toprule\n\\textbf{Model} & \\textbf{S42} & \\textbf{S123} & \\textbf{S456} & \\textbf{Mean} & \\textbf{$\\sigma$} \\\\\n\\midrule\nQwen-7B (7B)      & 93.61 & 96.00 & 97.65 & 95.75 & 2.05 \\\\\nDeepSeek (6.7B)    & 93.95 & 95.04 & 96.10 & 95.03 & 1.08 \\\\\nQwen-1.5B (1.5B)  & 95.63 & 97.65 & 96.72 & 96.67 & 1.01 \\\\\nCodeLlama (13B)    & 98.24 & 98.24 & 98.24 & \\textbf{98.24} & \\textbf{0.00} \\\\\n\\midrule\n\\multicolumn{4}{l}{Cross-model band} & \\multicolumn{2}{r}{[93.61, 98.24] = 4.63pp} \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\nAt tail-1024, four models reach 96.5--98.2\\% (CodeLlama 98.2\\% under label-only loss, three others 96.5--96.6\\%).\nScale and architecture differences that dominate the signal-poor regime (tail-256 range: 72.6--78.9\\%, 6.3pp) compress dramatically in the signal-rich regime.\n\n\\emph{Signal-poor convergence band}: head-2048 accuracies across all four models also converge into a narrow 75.3--81.8\\% band (6.5pp; Table~\\ref{tab:head_vs_tail}), comparable in width to the tail-256 band (72.6--78.9\\%, 6.3pp).\nWhen the diagnostic signal is absent (head-truncation discards trace terminus) or unreachable (tail-256 is too short), models of different scale and architecture collapse to similar performance, suggesting a shared floor determined by code comprehension rather than trace processing.\n\n\\emph{Scale behavior inversion}: in the signal-poor regime (tail-256), smaller models perform worse (Qwen-1.5B 72.6\\% vs.\\ Qwen-7B 78.9\\%, $-$6.3pp), mirroring the \\texttt{no\\_trace} scale pattern.\nIn the signal-rich regime (tail-512+), this reverses: Qwen-1.5B matches or exceeds Qwen-7B (95.6\\% vs.\\ 93.6\\% at tail-512; 97.9\\% vs.\\ 97.3\\% at tail-2048), consistent with sufficient trace signal eliminating the capacity advantage.\n\n\\emph{Non-monotonicity at long sequences}: two models show accuracy decreases beyond tail-1024.\nDeepSeek-6.7B drops $-$1.5pp from tail-1024 (96.5\\%) to tail-2048 (95.0\\%), consistent with its known long-context sensitivity (\\S\\ref{sec:training_dynamics}).\nCodeLlama-13B exhibits a more severe collapse: tail-2048 under label-only loss drops to 41.8\\% (vs.\\ tail-1024 = 98.2\\%), which we attribute to LoRA long-sequence instability under the label-only loss regime; this outlier is excluded from cross-model tail-2048 analysis.\nQwen-7B and Qwen-1.5B increase monotonically across all budgets.\n\nTable~\\ref{tab:head_vs_tail} shows the truncation direction effect: among the three models with complete data, tail-2048 outperforms head-2048 by 15.5--22.6pp.\nThe gap is largest for Qwen-1.5B (+22.6pp), indicating that smaller models benefit most from positional proximity to the diagnostic signal, as they lack the capacity to locate it within longer, noisier prefixes.\n\n%% ============================================================\n\\section{Calibration Analysis}\n\\label{sec:calibration_full}\n\nBeyond accuracy, we evaluate whether trace conditions affect prediction calibration, motivated by recent findings that code LLM confidence is often poorly calibrated \\citep{spiess2025calibration}.\n\n\\begin{table}[t]\n\\centering\n\\caption{Calibration metrics on Qwen-2.5-7B ($N{=}1{,}190$, seed=42). ECE = expected calibration error; Brier = Brier score. Lower is better for both.}\n\\label{tab:calibration}\n\\small\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Condition} & \\textbf{ECE $\\downarrow$} & \\textbf{Brier $\\downarrow$} \\\\\n\\midrule\nae\\_only & \\textbf{0.0004} & \\textbf{0.0008} \\\\\nexception\\_only & 0.0027 & 0.0013 \\\\\nVOTA & 0.0054 & 0.005 \\\\\nfull\\_trace & 0.096 & 0.144 \\\\\nno\\_trace & 0.171 & 0.197 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTable~\\ref{tab:calibration} shows that calibration quality mirrors the Tier~1/2 hierarchy.\nTier~1 conditions (\\texttt{ae\\_only}: ECE=0.0004; \\texttt{exception\\_only}: ECE=0.0027) produce near-perfectly calibrated predictions, while \\texttt{full\\_trace} (ECE=0.096) and \\texttt{no\\_trace} (ECE=0.171) exhibit substantial miscalibration.\nVOTA (ECE=0.0054) is well-calibrated but slightly worse than either Tier~1 component alone, reinforcing the pattern that combining trace signals dilutes rather than improves the prediction signal.\n\nThe Brier scores tell a consistent story: \\texttt{ae\\_only} (0.0008) and \\texttt{exception\\_only} (0.0013) achieve near-zero scores, while \\texttt{no\\_trace} (0.197) indicates substantial miscalibration.\n\n\\paragraph{Cross-model calibration.}\nTable~\\ref{tab:calibration_cross} extends the calibration analysis to four models (1.5B--13B) under \\texttt{exception\\_only}.\nAll four models achieve ECE ${<}$ 0.007 and Brier ${<}$ 0.007, indicating that calibration quality generalizes across architectures and scales.\nCodeLlama-13B achieves the lowest ECE (0.0020) and MCE (0.0411), while DeepSeek-6.7B shows the highest ECE (0.0064) and Brier (0.0061), consistent with its higher error rate (8 errors vs.\\ 2 for Qwen/CodeLlama).\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-model calibration for \\texttt{exception\\_only} ($N{=}1{,}190$, seed=42). ECE = expected calibration error; Brier = Brier score; MCE = maximum calibration error. All four models (1.5B--13B) achieve ECE ${<}$ 0.007.}\n\\label{tab:calibration_cross}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Model} & \\textbf{ECE $\\downarrow$} & \\textbf{Brier $\\downarrow$} & \\textbf{MCE $\\downarrow$} \\\\\n\\midrule\nQwen-1.5B & \\textbf{0.0020} & \\textbf{0.0013} & --- \\\\\nCodeLlama-13B & \\textbf{0.0020} & \\textbf{0.0013} & \\textbf{0.0411} \\\\\nQwen-7B & 0.0027 & \\textbf{0.0013} & 0.8355 \\\\\nDeepSeek-6.7B & 0.0064 & 0.0061 & 0.7756 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig2_calibration}\n\\caption{Reliability diagrams for four trace conditions on Qwen-2.5-7B ($N{=}1{,}190$, seed=42). \\texttt{exception\\_only} (ECE=0.0027) clusters near the diagonal, while \\texttt{no\\_trace} (ECE=0.171) exhibits systematic overconfidence, a 63$\\times$ gap.}\n\\label{fig:calibration}\n\\end{figure}\n\n%% ============================================================\n\\section{Error Overlap Analysis}\n\\label{sec:error_overlap}\n\nWe analyze the overlap between error sets of different conditions to determine whether they fail on the same samples (Figure~\\ref{fig:error_overlap}).\n\n\\texttt{exception\\_only}'s 2 errors (samples 901 and 905) have zero intersection with the error sets of all other conditions (Jaccard = 0.000 in all pairwise comparisons).\nThis orthogonality arises because \\texttt{exception\\_only} errors are caused by \\texttt{GeneratorExit} false positives (pass samples misclassified as fail due to benign \\texttt{BaseException} events), while errors from other conditions are predominantly fail samples misclassified as pass due to insufficient signal.\n\nAmong non-exception conditions, error sets exhibit hierarchical containment: \\texttt{ae\\_only} $\\subset$ VOTA $\\subset$ \\texttt{loop\\_only} $\\subset$ \\texttt{no\\_trace}, with pairwise Jaccard indices increasing with signal overlap.\n\\texttt{loop\\_only} and \\texttt{full\\_trace} share the highest overlap (Jaccard ${\\sim}$0.65), reflecting their shared reliance on behavioral patterns rather than explicit fault indicators.\n\nThis analysis indicates that \\texttt{exception\\_only} operates on an independent signal dimension: its errors are representation ambiguities (iterator protocol artifacts) rather than information deficits, explaining why combining it with other signals cannot eliminate these specific errors.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{error_overlap}\n\\caption{Jaccard similarity between error sets of different conditions (Qwen-7B, seed=42, $N{=}1{,}190$). \\texttt{exception\\_only} (exc\\_only) has zero overlap with all other conditions, indicating it operates on an independent signal dimension.}\n\\label{fig:error_overlap}\n\\end{figure}\n\n%% ============================================================\n\\section{Cross-Dataset Generalization: DebugBench}\n\\label{sec:debugbench_full}\n\nTo test whether exception-based verdict prediction generalizes beyond LLM-generated solutions, we evaluate on DebugBench \\citep{tian2024debugbench}, a dataset of human-written programs with synthetically injected bugs (single-point mutations such as operator replacement, variable misuse, and missing statements).\nAfter filtering for executable Python samples with valid traces, we retain 426 samples with a near-balanced class distribution (majority baseline: 51.4\\%).\n\n\\begin{table}[t]\n\\centering\n\\caption{Generalization to DebugBench ($N{=}426$, Qwen-2.5-7B, seed=42). Wilson 95\\% CIs. The component ranking (exception\\_only $\\geq$ VOTA $>$ no\\_trace) is preserved, and exception\\_only achieves perfect accuracy.}\n\\label{tab:debugbench}\n\\small\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Condition} & \\textbf{Acc (\\%)} & \\textbf{95\\% CI} \\\\\n\\midrule\nexception\\_only & \\textbf{100.00} & [99.14, 100.00] \\\\\nVOTA & 99.77 & [99.30, 100.00] \\\\\nno\\_trace & 96.71 & [94.80, 98.40] \\\\\n\\midrule\nMajority baseline & 51.41 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTable~\\ref{tab:debugbench} shows that the component ranking from the main experiments is preserved: \\texttt{exception\\_only} (100.00\\%) $\\geq$ VOTA (99.77\\%) $>$ \\texttt{no\\_trace} (96.71\\%).\nThe \\texttt{exception\\_only} condition achieves perfect accuracy, showing that the exception-based representation generalizes to a different fault distribution without degradation.\n\nThe absolute margins are much narrower than on the main dataset: the \\texttt{no\\_trace} baseline already achieves 96.71\\% (compared to 75.13\\% on HumanEval+MBPP), leaving only 3.29pp of headroom for trace-based improvement.\nThis ceiling effect reflects a fundamental difference in fault characteristics: DebugBench bugs are synthetically injected single-point mutations, which produce code that is structurally dissimilar from the original correct solution; a model can often identify the fault from source code alone.\nIn contrast, the HumanEval+MBPP solutions are LLM-generated, producing natural errors (logic mistakes, edge-case failures) where the faulty and correct solutions may be structurally similar, making code-only verdict prediction substantially harder.\n\nThese results support exception-based verdict prediction as a generalizable approach: the method does not degrade on an out-of-distribution dataset, and the exception dominance ranking (exception\\_only $\\geq$ VOTA $>$ no\\_trace) is consistent across both datasets. However, the narrow DebugBench margins are insufficient to independently validate trace importance.\nThe 24.70pp trace lift on the main dataset (no\\_trace 75.13\\% $\\to$ exception\\_only 99.83\\%) remains the primary evidence for the value of exception-based trace signals.\n\n%% ============================================================\n\\section{Cross-Model Robustness Analysis}\n\\label{sec:robustness_analysis}\n\nThe cross-model gap pattern (Table~\\ref{tab:cross_model}) suggests a design principle: \\emph{trace representations should match the model capability floor, not the ceiling.}\nException events are consistently the most effective component on both models, and their structural simplicity (a fixed-format error message) ensures that the relative advantage over richer representations holds across all seeds.\nAll three DeepSeek \\texttt{exception\\_only} seeds achieve ${\\geq}$99.33\\% (99.33/99.50/99.33, $\\sigma{=}$0.10pp), matching Qwen and CodeLlama at ${\\geq}$99.83\\%.\nVOTA achieves ${\\geq}$98.57\\% across all models when excluding outlier seeds (cross-model range: 0.80pp), but DeepSeek VOTA exhibits seed-dependent instability: seed 42 (84.45\\%) is a training failure due to tokenizer-induced truncation (91.7\\% of training samples affected), while seeds 123/456 (99.16\\%/99.33\\%) match cross-model performance.\nThis VOTA instability is confounded by tokenizer efficiency and base model differences \\citep{yang2024generalization}.\nOur \\texttt{exception\\_only} design sidesteps the truncation confound entirely: inputs have a median of 150 tokens (mean 398), well below the 2{,}048-token context window, so no training samples are truncated on either model.\nThe resulting 0.50pp cross-model gap (Table~\\ref{tab:cross_model}) is therefore a clean measure of model capability differences, making the ``capability floor'' principle directly testable.\nThe practical implication is that trace-based systems should default to the simplest sufficient signal.\n\n%% ============================================================\n\\section{Training Dynamics and Loss Decoupling}\n\\label{sec:training_dynamics}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{training_dynamics}\n\\caption{Training dynamics: \\texttt{exception\\_only} converges to 99.83\\% by step 150; \\texttt{full\\_trace} with label-only loss oscillates (82--89\\%) without convergence.}\n\\label{fig:training_dynamics}\n\\end{figure}\n\nThe DeepSeek \\texttt{exception\\_only} results are consistent across all three seeds (99.33/99.50/99.33, $\\sigma{=}$0.10pp), matching Qwen's cross-seed stability.\nEpoch-level analysis shows mild degradation in seed 42: accuracy peaks at 99.83\\% after epoch~1 but settles at 99.33\\% by epoch~3 ($-$0.50pp), while seed 456 shows no degradation (99.33\\% at both epochs).\nEarly stopping may yield marginal gains, but the epoch effect is small (${\\leq}$0.5pp).\nThe practical recommendation: for deployment, use task-specific metrics (accuracy, fail recall) for checkpoint and seed selection rather than training loss, and train multiple seeds to select the best.\n\nThe contrast with VOTA is instructive: DeepSeek VOTA seed 42 accuracy monotonically increases from 78.15\\% to 84.45\\% across epochs, consistent with a performance limit from high trace truncation (91.7\\% of samples; \\S\\ref{sec:tokenizer_analysis}).\nSeeds 123/456, which avoid the truncation-sensitive initialization basin, achieve 99.16\\%/99.33\\%, indicating that the deficit is seed-specific rather than a fundamental model limitation.\n\n%% ============================================================\n\\section{Deduplication Statistics}\n\\label{sec:dedup_stats}\n\nTable~\\ref{tab:dedup} reports the duplication rates across trace formats.\nBecause multiple passing solutions to the same problem produce identical (input, output) pairs in the \\texttt{exception\\_only} format (correct executions raise no exceptions, so the trace content is the same regardless of the solution's internal logic), the dataset contains duplicate rows.\nTrain--test input overlap is zero (split by problem ID), so no information leakage occurs.\nThe high duplication in \\texttt{exception\\_only} does not affect our experimental conclusions: after deduplication the training set still contains 2,858 unique samples and the test set 607, providing sufficient coverage for the 591-problem benchmark.\n\n\\paragraph{Problem-level partitioning and sensitivity analysis.}\nData is partitioned at the problem level: 472 training problems and 119 test problems, with zero crossover.\nDuplicates arise from multiple candidate solutions per problem (up to 10 solutions each), not from cross-problem overlap.\nTo verify that deduplication does not alter any finding, we ran a sensitivity analysis across all 19 experimental conditions (7 trace formats $\\times$ 4 models, minus conditions not run): deduplication produces a negligible ($<$0.1pp) accuracy delta in every case.\nThis shows that duplicate samples neither inflate nor deflate accuracy, because duplicates share the same ground-truth label and the model's prediction is deterministic at inference time.\nDuplicates arise because the \\texttt{exception\\_only} format collapses passing solutions (which share identical ``no exception'' output) into identical rows; the redundancy is a property of the format's compactness for pass-class samples.\nThe \\texttt{exception\\_only} test set contains 48.99\\% such duplicates; all confidence intervals treat samples as independent Bernoulli trials.\n\n\\begin{table}[t]\n\\centering\n\\caption{Deduplication statistics. The \\texttt{exception\\_only} format collapses multiple passing solutions into identical rows because correct executions produce no exception events. Train--test input overlap is 0 (no leakage).}\n\\label{tab:dedup}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Split} & \\textbf{Total} & \\textbf{Unique} & \\textbf{Dup.\\ rate} \\\\\n\\midrule\nexception\\_only train & 4{,}720 & 2{,}858 & 39.45\\% \\\\\nexception\\_only test  & 1{,}190 &   607 & 48.99\\% \\\\\nraw\\_traces (full)    & 5{,}910 & 5{,}803 &  1.81\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n%% ============================================================\n\\section{Regex Baseline Analysis}\n\\label{sec:regex_baselines}\n\nTo establish a non-learning upper bound, we evaluate six regex-based baselines on the \\texttt{exception\\_only} test set ($N{=}1{,}190$) and two format-specific baselines on VOTA and \\texttt{full\\_trace} inputs.\n\n\\begin{table}[t]\n\\centering\n\\caption{Regex baseline accuracy ($N{=}1{,}190$). B4 is the strongest semantic baseline (6.22pp below SFT \\texttt{exception\\_only}, McNemar $p{<}.001$). B6 uses an error count threshold. $^\\ddag$B5 exploits a data formatting artifact: the \\texttt{[No exception data in trace]} marker is deterministically present in all pass samples, making this a format-level shortcut rather than a genuine exception-based heuristic.}\n\\label{tab:regex}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llc}\n\\toprule\n\\textbf{Baseline} & \\textbf{Method} & \\textbf{Acc (\\%)} \\\\\n\\midrule\nB1: \\texttt{[ERROR]} presence & string match & 93.45 \\\\\nB2: Traceback presence & string match & 71.51 \\\\\nB3: Any keyword & union of B1+B2+Exception & 93.45 \\\\\nB4: Exception type regex & regex on exception class names & \\textbf{93.61} \\\\\nB5: Format marker & \\texttt{[No exception data]} $\\to$ pass & 99.33$^\\ddag$ \\\\\nB6: Error count $\\geq$2 & count threshold & 92.02 \\\\\n\\midrule\nVOTA format regex & best regex on VOTA traces & 75.55 \\\\\nfull\\_trace format regex & best regex on full traces & 77.39 \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\nThe strongest legitimate baseline (B4, 93.61\\%) applies regex pattern-matching on Python exception class names (e.g., \\texttt{ValueError}, \\texttt{TypeError}).\nIts errors concentrate on 8 boundary samples where a \\texttt{ValueError} is raised inside a \\texttt{try/except} block and caught; the program passes despite an exception occurring in the trace.\nSFT \\texttt{exception\\_only} correctly classifies 6 of these 8 samples, indicating that the model learns the semantic distinction between caught (benign) and uncaught (fault-indicating) exceptions.\nB5 (99.33\\%) achieves near-SFT accuracy but relies on the deterministic presence of a format marker in pass-class traces, which is an artifact of the trace preprocessing pipeline rather than a generalizable signal; McNemar test vs.\\ SFT yields $p{=}.041$, indicating a statistically significant difference.\n\n\\paragraph{Cross-format comparison.}\nTable~\\ref{tab:regex_cross_format} compares SFT and the best applicable regex baseline for each trace format.\nThe SFT advantage increases with format complexity: \\texttt{no\\_trace} (+3.62pp over majority baseline) $<$ \\texttt{full\\_trace} (+4.37pp) $<$ \\texttt{exception\\_only} (+6.22pp) $\\ll$ VOTA (+23.86pp).\nThe VOTA gap is largest because its structured multi-component format carries semantic content that regex cannot parse, while \\texttt{exception\\_only}'s simpler format allows regex to capture most of the signal.\n\n\\begin{table}[t]\n\\centering\n\\caption{SFT vs.\\ best regex baseline by trace format ($N{=}1{,}190$). Regex baselines: majority class for \\texttt{no\\_trace}, keyword matching for \\texttt{full\\_trace}, pattern matching for VOTA, exception type regex (B4) for \\texttt{exception\\_only}.}\n\\label{tab:regex_cross_format}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Format} & \\textbf{SFT (\\%)} & \\textbf{Regex (\\%)} & \\textbf{$\\Delta$ (pp)} \\\\\n\\midrule\nexception\\_only & 99.83 & 93.61 & +6.22 \\\\\nVOTA & 99.05 & 75.55 & +23.50 \\\\\nfull\\_trace & 81.76 & 77.39 & +4.37 \\\\\nno\\_trace & 75.13 & 71.51 & +3.62 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n%% ============================================================\n\\section{Cross-Model Zero-Shot Comparison}\n\\label{sec:zeroshot_cross_model}\n\nTable~\\ref{tab:zeroshot_cross_model} compares zero-shot and SFT \\texttt{exception\\_only} accuracy across four models.\nZero-shot performance does not correlate with model size: the smallest model (Qwen-1.5B, 93.45\\%) outperforms all larger models, while the largest (CodeLlama-13B) falls below majority baseline.\nSFT compresses the 42.44pp zero-shot range to 0.50pp, eliminating architecture-dependent variance.\n\n\\begin{table}[t]\n\\centering\n\\caption{Zero-shot vs.\\ SFT \\texttt{exception\\_only} across four models ($N{=}1{,}190$). Zero-shot accuracy is uncorrelated with model size; SFT normalizes cross-architecture variance from 42.44pp to 0.50pp.}\n\\label{tab:zeroshot_cross_model}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Model} & \\textbf{Size} & \\textbf{Zero-shot (\\%)} & \\textbf{SFT (\\%)} & \\textbf{$\\Delta$ (pp)} \\\\\n\\midrule\nQwen-1.5B & 1.5B & 93.45 & 99.83 & +6.38 \\\\\nDeepSeek-6.7B & 6.7B & 90.59 & 99.39 & +8.80 \\\\\nQwen-7B & 7B & 89.08 & 99.83 & +10.75 \\\\\nCodeLlama-13B & 13B & 51.01 & 99.89 & +48.88 \\\\\n\\midrule\nRange & --- & 42.44pp & 0.50pp & --- \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\\subsection{Calibration Analysis}\n\\label{sec:calibration_analysis}\n\n\\begin{table}[h]\n\\centering\n\\caption{Model calibration on \\texttt{exception\\_only} (seed 42). All four models achieve ECE $<$ 0.005, indicating that near-perfect accuracy reflects genuine confidence rather than overfit predictions.}\n\\label{tab:calibration_model_level}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Accuracy} & \\textbf{ECE $\\downarrow$} & \\textbf{Brier $\\downarrow$} & \\textbf{Mean Conf.} \\\\\n\\midrule\nQwen-2.5-1.5B & 99.83\\% & 0.0014 & 0.0013 & 99.82\\% \\\\\nQwen-2.5-7B & 99.83\\% & 0.0017 & 0.0013 & 99.80\\% \\\\\nCodeLlama-13B & 99.83\\% & 0.0020 & 0.0013 & 99.63\\% \\\\\nDeepSeek-6.7B & 99.33\\% & 0.0048 & 0.0059 & 99.71\\% \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n%% ============================================================\n\\section{Use of AI Assistants}\n\\label{app:ai-assistants}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant\nthroughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing\n    pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections,\n    polishing prose, and reformatting LaTeX.\n    \\item \\textbf{Literature:} summarizing related papers to inform\n    the related-work section.\n\\end{itemize}\n",
      "numLines": 845,
      "startLine": 1,
      "totalLines": 845
    }
  }
}
```

</details>

---


### Tool call

_source line 31_

<details open><summary>🔧 Tool call — Agent · `toolu_015nThs5u5v32WJHrbmn69eM`</summary>

```json
{
  "description": "Parse registry JSON for audit",
  "prompt": "I need you to parse a large JSON registry file and extract all experiment metrics for a paper data audit.\n\nThe file is at: /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\n\nIt's JSON with schema: {result: string} — the `result` field is itself a JSON string that needs to be parsed.\n\nPlease use Python to:\n1. Load the file, parse the outer JSON, then parse the inner `result` string\n2. For each experiment, extract: exp_id, status, metrics (especially accuracy, mean, std, seeds, ECE, Brier, CI, etc.), and any tags/labels\n3. Group experiments by their type/condition (e.g., exception_only, full_trace, ae_only, VOTA, loop_only, no_trace, regex, majority, ablation, density/gradient masking, cross-dataset, nomarker, SFT, etc.)\n\nOutput a comprehensive structured summary with ALL numeric metrics for every experiment. I need exact numbers - don't round or summarize. Include exp_id for each.\n\nFocus especially on:\n- Table 1 experiments (cross_model): exception_only, ae_only, VOTA, loop_only, full_trace, no_trace for models GPT-4o, Claude-3.5, Gemini-2.0, DeepSeek-V3\n- Table 2 experiments (ablation): different conditions with accuracy, CI, tier\n- Table 3 experiments (density decomposition): exception_only, gradient masking, full_trace, label-only\n- Regex baseline and Majority baseline numbers\n- Any nomarker experiments\n- Any cross-dataset experiments\n- ECE and Brier score values\n\nWrite the output to /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts/_audit_registry_extract.txt so I can read it.",
  "model": "sonnet"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "6cc0462e-3243-4cce-9237-903410ae17de",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012brTbzezUo9HdHSffBPKci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1489,
      "cache_read_input_tokens": 25293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1489
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


### System

_source line 32_

```json
{
  "type": "system",
  "subtype": "task_started",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Parse registry JSON for audit",
  "task_type": "local_agent",
  "prompt": "I need you to parse a large JSON registry file and extract all experiment metrics for a paper data audit.\n\nThe file is at: /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\n\nIt's JSON with schema: {result: string} — the `result` field is itself a JSON string that needs to be parsed.\n\nPlease use Python to:\n1. Load the file, parse the outer JSON, then parse the inner `result` string\n2. For each experiment, extract: exp_id, status, metrics (especially accuracy, mean, std, seeds, ECE, Brier, CI, etc.), and any tags/labels\n3. Group experiments by their type/condition (e.g., exception_only, full_trace, ae_only, VOTA, loop_only, no_trace, regex, majority, ablation, density/gradient masking, cross-dataset, nomarker, SFT, etc.)\n\nOutput a comprehensive structured summary with ALL numeric metrics for every experiment. I need exact numbers - don't round or summarize. Include exp_id for each.\n\nFocus especially on:\n- Table 1 experiments (cross_model): exception_only, ae_only, VOTA, loop_only, full_trace, no_trace for models GPT-4o, Claude-3.5, Gemini-2.0, DeepSeek-V3\n- Table 2 experiments (ablation): different conditions with accuracy, CI, tier\n- Table 3 experiments (density decomposition): exception_only, gradient masking, full_trace, label-only\n- Regex baseline and Majority baseline numbers\n- Any nomarker experiments\n- Any cross-dataset experiments\n- ECE and Brier score values\n\nWrite the output to /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts/_audit_registry_extract.txt so I can read it.",
  "uuid": "34ed458f-af30-4b7e-bcd6-a0705c281bb6",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


## Round 1

## Round 1

52 recorded events


### User

_source line 33 · 2026-05-23T19:17:45.491Z_

I need you to parse a large JSON registry file and extract all experiment metrics for a paper data audit.

The file is at: /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt

It's JSON with schema: {result: string} — the `result` field is itself a JSON string that needs to be parsed.

Please use Python to:
1. Load the file, parse the outer JSON, then parse the inner `result` string
2. For each experiment, extract: exp_id, status, metrics (especially accuracy, mean, std, seeds, ECE, Brier, CI, etc.), and any tags/labels
3. Group experiments by their type/condition (e.g., exception_only, full_trace, ae_only, VOTA, loop_only, no_trace, regex, majority, ablation, density/gradient masking, cross-dataset, nomarker, SFT, etc.)

Output a comprehensive structured summary with ALL numeric metrics for every experiment. I need exact numbers - don't round or summarize. Include exp_id for each.

Focus especially on:
- Table 1 experiments (cross_model): exception_only, ae_only, VOTA, loop_only, full_trace, no_trace for models GPT-4o, Claude-3.5, Gemini-2.0, DeepSeek-V3
- Table 2 experiments (ablation): different conditions with accuracy, CI, tier
- Table 3 experiments (density decomposition): exception_only, gradient masking, full_trace, label-only
- Regex baseline and Majority baseline numbers
- Any nomarker experiments
- Any cross-dataset experiments
- ECE and Brier score values

Write the output to /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts/_audit_registry_extract.txt so I can read it.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "02816b3a-cff5-4c24-bf6a-275a25ab3188"
}
```

</details>

---


### System

_source line 34_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Check if the target file exists",
  "usage": {
    "total_tokens": 15099,
    "tool_uses": 1,
    "duration_ms": 3117
  },
  "last_tool_name": "Bash",
  "uuid": "1ab77e01-8f2e-44e2-958c-232b69726595",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 35_

<details open><summary>🔧 Tool call — Bash · `toolu_01HxSyBXfPXMdn8iENhajHv7`</summary>

```json
{
  "command": "ls /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt 2>/dev/null && echo \"FILE_EXISTS\" || echo \"FILE_NOT_FOUND\"",
  "description": "Check if the target file exists"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "773caa42-08d4-41ee-942c-b7fcaaf08dff",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_01HdN6cstgA9GNdbWNAwNWDK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 15045,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 15045,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 51,
      "service_tier": "standard",
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

_source line 36 · 2026-05-23T19:17:48.766Z_

<details><summary>↩ Tool result · `toolu_01HxSyBXfPXMdn8iENhajHv7`</summary>

```text
/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt
FILE_EXISTS
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "fea77840-92ee-40ea-aac5-82cacde7b2a0"
}
```

</details>

---


### System

_source line 37_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Parse outer JSON and inspect inner result",
  "usage": {
    "total_tokens": 16271,
    "tool_uses": 2,
    "duration_ms": 10879
  },
  "last_tool_name": "Bash",
  "uuid": "bee62f58-af75-41c3-a85b-1382c9de49f8",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 38_

<details open><summary>🔧 Tool call — Bash · `toolu_01ChuU9rMZBAdVqB4dS1k7K1`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\nprint(\"Outer keys:\", list(outer.keys()))\nresult_str = outer.get('result', '')\nprint(\"Result type:\", type(result_str))\nprint(\"Result length:\", len(result_str))\nprint(\"First 500 chars:\", result_str[:500])\nPYEOF\n",
  "description": "Parse outer JSON and inspect inner result"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "baa3d920-8670-4594-bfad-e65e540c0127",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_016RFPXsaGpVx4eAbsZzCvbh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1130,
      "cache_read_input_tokens": 15045,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1130,
        "ephemeral_1h_input_tokens": 0
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

_source line 39 · 2026-05-23T19:17:56.493Z_

<details><summary>↩ Tool result · `toolu_01ChuU9rMZBAdVqB4dS1k7K1`</summary>

```text
Outer keys: ['result']
Result type: &lt;class 'str'>
Result length: 329949
First 500 chars: {"success": true, "data": {"experiments": {"deepseek_gradient_masking_seed123": {"status": "DONE", "retry_count": 0, "created_at": "2026-05-23T09:51:05.056Z", "updated_at": "2026-05-23T13:45:23.758Z", "hypothesis": "DeepSeek-6.7B gradient masking multi-seed validation (seed 123): 99.8% gradient masking should achieve ≥98.5% accuracy, confirming dilution bound stability. Derived from deepseek_gradient_masking_seed42 (99.33%, dilution 0.06%).", "parent": "deepseek_gradient_masking_seed42", "spec":
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "2d1036ea-29e5-44be-8bd7-09113acc4fd9"
}
```

</details>

---


### System

_source line 40_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Parse inner JSON and list all experiment IDs",
  "usage": {
    "total_tokens": 16821,
    "tool_uses": 3,
    "duration_ms": 15036
  },
  "last_tool_name": "Bash",
  "uuid": "091aa1b2-dba9-4c0d-bc82-760a73dd3f4a",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 41_

<details open><summary>🔧 Tool call — Bash · `toolu_01GH3z3GyEnLnCdVAmnm41CK`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\nimport os\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\nresult_str = outer['result']\ninner = json.loads(result_str)\n\nprint(\"Inner keys:\", list(inner.keys()))\ndata = inner.get('data', {})\nprint(\"Data keys:\", list(data.keys()))\nexperiments = data.get('experiments', {})\nprint(\"Total experiments:\", len(experiments))\nprint(\"\\nAll experiment IDs:\")\nfor eid in sorted(experiments.keys()):\n    print(\" -\", eid)\nPYEOF\n",
  "description": "Parse inner JSON and list all experiment IDs"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "9d21b8b4-acbc-423c-9370-b594ce36af37",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_018AA4cSKfaxGQXEY71NzGPZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 496,
      "cache_read_input_tokens": 16175,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 496,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 54,
      "service_tier": "standard",
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

_source line 42 · 2026-05-23T19:18:00.632Z_

<details><summary>↩ Tool result · `toolu_01GH3z3GyEnLnCdVAmnm41CK`</summary>

```text
Inner keys: ['success', 'data', 'error', 'metadata']
Data keys: ['experiments', 'count', 'total', 'baseline']
Total experiments: 188

All experiment IDs:
 - ae_only_seed123
 - ae_only_seed456
 - attention_gradient_analysis
 - calibration_analysis_seed42
 - codellama13b_ae_only_seed123
 - codellama13b_ae_only_seed42
 - codellama13b_exception_only_seed123
 - codellama13b_exception_only_seed42
 - codellama13b_exception_only_seed456
 - codellama13b_full_trace_head2048_seed42
 - codellama13b_full_trace_tail1024_seed42
 - codellama13b_full_trace_tail1024_seed42_v2
 - codellama13b_full_trace_tail1024_seed42_v3
 - codellama13b_full_trace_tail2048_seed42
 - codellama13b_full_trace_tail2048_seed42_v2
 - codellama13b_full_trace_tail2048_seed42_v3
 - codellama13b_full_trace_tail256_seed42
 - codellama13b_full_trace_tail384_seed42
 - codellama13b_full_trace_tail512_seed123
 - codellama13b_full_trace_tail512_seed42
 - codellama13b_full_trace_tail512_seed456
 - codellama13b_label_only_seed123_v2
 - codellama13b_label_only_seed42
 - codellama13b_label_only_seed42_v2
 - codellama13b_loop_only_seed123
 - codellama13b_loop_only_seed42
 - codellama13b_loop_only_seed456
 - codellama13b_no_trace_seed42
 - codellama13b_nomarker_seed42
 - codellama13b_vota_seed123
 - codellama13b_vota_seed42
 - codellama_exception_only_seed42
 - codellama_gradient_masking_seed42
 - codellama_no_trace_seed42
 - codellama_vota_seed42
 - cross_dataset_batch
 - cross_he2mbpp_exception_only_seed42
 - cross_he2mbpp_no_trace_seed42
 - cross_mbpp2he_exception_only_seed42
 - cross_mbpp2he_no_trace_seed42
 - cross_model_calibration
 - cross_model_calibration_eval
 - debugbench_exception_bug_fix
 - debugbench_exception_only_seed42
 - debugbench_no_trace_seed42
 - debugbench_vota_seed42
 - deepseek_ae_only_seed123
 - deepseek_ae_only_seed42
 - deepseek_exception_only_seed123
 - deepseek_exception_only_seed123_v2
 - deepseek_exception_only_seed42
 - deepseek_exception_only_seed456
 - deepseek_full_trace_head2048_seed42
 - deepseek_full_trace_seed42
 - deepseek_full_trace_seed42_v2
 - deepseek_full_trace_seed42_v3
 - deepseek_full_trace_tail1024_seed42
 - deepseek_full_trace_tail2048_seed42
 - deepseek_full_trace_tail256_seed42
 - deepseek_full_trace_tail384_seed42
 - deepseek_full_trace_tail512_seed123
 - deepseek_full_trace_tail512_seed123_v2
 - deepseek_full_trace_tail512_seed42
 - deepseek_full_trace_tail512_seed456
 - deepseek_gradient_masking_seed123
 - deepseek_gradient_masking_seed42
 - deepseek_label_only_seed42
 - deepseek_loop_only_seed123
 - deepseek_loop_only_seed42
 - deepseek_loop_only_seed456
 - deepseek_no_trace_seed123
 - deepseek_no_trace_seed42
 - deepseek_vota_seed123
 - deepseek_vota_seed42
 - deepseek_vota_seed456
 - eval_missing_predictions_batch
 - eval_missing_predictions_batch_v2
 - exc_message_only_seed42
 - exc_stacktrace_only_seed42
 - exc_type_only_seed42
 - exception_only_nomarker_seed123
 - exception_only_nomarker_seed42
 - exception_only_nomarker_seed456
 - exception_only_padded2048_seed42
 - exception_only_seed123
 - exception_only_seed456
 - fewshot_gpt41_exception_only_0shot
 - fewshot_gpt41_exception_only_3shot
 - fewshot_gpt41_no_trace_0shot
 - fewshot_gpt4o_exception_only_0shot
 - fewshot_gpt4o_exception_only_3shot
 - fewshot_gpt4o_no_trace_0shot
 - fewshot_qwen7b_exception_only
 - full_trace_1024tok_seed42
 - full_trace_2048tok_seed42
 - full_trace_256tok_seed42
 - full_trace_512tok_seed42
 - full_trace_label_only_seed42
 - full_trace_seed123
 - full_trace_seed42
 - full_trace_seed42_v2
 - full_trace_seed42_v5
 - full_trace_seed456
 - full_trace_tail256_seed42
 - full_trace_tail_1024_seed42
 - full_trace_tail_256_seed42
 - full_trace_tail_512_seed42
 - full_trace_tail_seed42
 - gradient_masking_qwen7b_seed123
 - gradient_masking_qwen7b_seed42
 - gradient_masking_qwen7b_seed456
 - label_only_seed123
 - label_only_seed456
 - loop_only_seed123
 - loop_only_seed456
 - no_trace_seed123
 - no_trace_seed42
 - no_trace_seed42_v2
 - no_trace_seed42_v3
 - no_trace_seed42_v4
 - no_trace_seed42_v5
 - no_trace_seed456
 - nomarker_cross_he2mbpp_exception_only
 - qwen1.5b_exception_only_seed42
 - qwen1.5b_full_trace_seed42
 - qwen1.5b_no_trace_seed42
 - qwen1.5b_vota_seed42
 - qwen15b_ae_only_seed123
 - qwen15b_ae_only_seed42
 - qwen15b_exception_only_seed123
 - qwen15b_exception_only_seed123_v2
 - qwen15b_exception_only_seed42
 - qwen15b_exception_only_seed456
 - qwen15b_full_trace_head2048_seed42
 - qwen15b_full_trace_seed42
 - qwen15b_full_trace_tail1024_seed42
 - qwen15b_full_trace_tail2048_seed42
 - qwen15b_full_trace_tail256_seed42
 - qwen15b_full_trace_tail384_seed42
 - qwen15b_full_trace_tail512_seed123
 - qwen15b_full_trace_tail512_seed42
 - qwen15b_full_trace_tail512_seed456
 - qwen15b_label_only_seed123_v2
 - qwen15b_label_only_seed42
 - qwen15b_label_only_seed42_v2
 - qwen15b_label_only_seed456_v2
 - qwen15b_loop_only_seed123
 - qwen15b_loop_only_seed42
 - qwen15b_loop_only_seed456
 - qwen15b_no_trace_seed123
 - qwen15b_no_trace_seed42
 - qwen15b_no_trace_seed456
 - qwen15b_nomarker_seed42
 - qwen15b_vota_seed123
 - qwen15b_vota_seed42
 - qwen7b_exception_only_dynamics_seed42
 - qwen7b_full_trace_dynamics_seed42
 - qwen7b_full_trace_head2048_seed42
 - qwen7b_full_trace_label_only_seed123
 - qwen7b_full_trace_label_only_seed456
 - qwen7b_full_trace_seed123
 - qwen7b_full_trace_seed456
 - qwen7b_full_trace_seed456_v2
 - qwen7b_full_trace_tail384_seed42
 - qwen7b_full_trace_tail512_seed123
 - qwen7b_full_trace_tail512_seed42
 - qwen7b_full_trace_tail512_seed456
 - qwen7b_vota_seed123
 - qwen7b_vota_seed456
 - regex_baseline_analysis
 - regex_nomarker_baseline
 - vota_ae_only_seed42
 - vota_exception_only_seed42
 - vota_exception_only_seed42_v2
 - vota_loop_only_seed42
 - vota_no_ae_seed42
 - vota_seed123
 - vota_seed42
 - vota_seed42_v2
 - vota_seed42_v3
 - vota_seed42_v4
 - vota_seed42_v5
 - vota_seed456
 - vota_seed456_v2
 - zeroshot_codellama13b_exception_only
 - zeroshot_deepseek7b_exception_only
 - zeroshot_qwen15b_exception_only
 - zeroshot_qwen7b_exception_only
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "5ac85e88-ceec-41c8-84b7-384c9d745d5a"
}
```

</details>

---


### System

_source line 43_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Inspect a few experiment schemas to understand field structure",
  "usage": {
    "total_tokens": 19895,
    "tool_uses": 4,
    "duration_ms": 21549
  },
  "last_tool_name": "Bash",
  "uuid": "953d3887-df1c-4141-9843-806d389778a9",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 44_

<details open><summary>🔧 Tool call — Bash · `toolu_01WY9Vkr3aTgjxYLR4aWq5ZJ`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\ninner = json.loads(outer['result'])\nexperiments = inner['data']['experiments']\nbaseline = inner['data'].get('baseline', {})\n\n# Inspect a few experiments to understand schema\nsample_ids = list(experiments.keys())[:3]\nfor eid in sample_ids:\n    print(f\"\\n=== {eid} ===\")\n    exp = experiments[eid]\n    print(json.dumps(exp, indent=2)[:2000])\n    print(\"...\")\nPYEOF\n",
  "description": "Inspect a few experiment schemas to understand field structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "12310fb6-74e1-478a-b73c-e1b77339e38c",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_015ZbXiBhfqGiNuK8yztYkXy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3030,
      "cache_read_input_tokens": 16671,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3030,
        "ephemeral_1h_input_tokens": 0
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

_source line 45 · 2026-05-23T19:18:07.121Z_

<details><summary>↩ Tool result · `toolu_01WY9Vkr3aTgjxYLR4aWq5ZJ`</summary>

```text
=== deepseek_gradient_masking_seed123 ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-23T09:51:05.056Z",
  "updated_at": "2026-05-23T13:45:23.758Z",
  "hypothesis": "DeepSeek-6.7B gradient masking multi-seed validation (seed 123): 99.8% gradient masking should achieve \u226598.5% accuracy, confirming dilution bound stability. Derived from deepseek_gradient_masking_seed42 (99.33%, dilution 0.06%).",
  "parent": "deepseek_gradient_masking_seed42",
  "spec": {
    "command": "bash -c \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/trace-verdict-study && python train/train_sft.py --condition exception_only --model_path deepseek-coder-6.7b-instruct --gradient_mask_ratio 0.998 --gradient_checkpointing --seed 123\"",
    "server": "westd-11235",
    "gpu": [
      "cuda:0"
    ],
    "pid": "874893",
    "log_path": "~/runs/trace-verdict-study/deepseek_gradient_masking_seed123.log",
    "data_path": "/root/trace-verdict-study/data/exception_only_train.jsonl",
    "data_count": 4720,
    "model_name": "deepseek-ai/deepseek-coder-6.7b-instruct",
    "seed": 123,
    "checkpoint_source": "trained_from_scratch",
    "eval_data": "/root/trace-verdict-study/data/exception_only_test.jsonl",
    "checkpoint_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/deepseek_gradient_masking_seed123/final/"
  },
  "metrics": {
    "accuracy": 0.9395,
    "pass_precision": 0.924,
    "pass_recall": 0.998,
    "pass_f1": 0.959,
    "fail_precision": 0.993,
    "fail_recall": 0.794,
    "fail_f1": 0.882
  },
  "conclusion": "negative",
  "completed_at": "2026-05-23T13:45:23.758Z"
}
...

=== codellama_gradient_masking_seed42 ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-23T08:52:00.476Z",
  "updated_at": "2026-05-23T11:40:38.570Z",
  "hypothesis": "Cross-architecture gradient masking validation: CodeLlama-13B exception_only with 99.8% gradient masking should achieve \u226598.5% accuracy (vs baseline 99.89%\u00b10.10), extending \u22644% dilution bound to third architecture family (Qwen + DeepSeek + CodeLlama)",
  "spec": {
    "checkpoint_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/codellama_gradient_masking_seed42/final",
    "log_path": "~/runs/trace-verdict-study/codellama_gradient_masking_seed42.log"
  },
  "reproduce": {
    "finished_at": "2026-05-23T11:30:59.992Z"
  },
  "extra": {
    "hook_events": [
      {
        "event": "on_complete",
        "action": "agent",
        "ts": "2026-05-23T11:31:06.685621+00:00"
      }
    ]
  },
  "metrics": {
    "accuracy": 1,
    "accuracy_ci_lower": 1,
    "accuracy_ci_upper": 1,
    "eval_loss": 0.0625,
    "dilution_pct": -0.11,
    "pass_f1": 1,
    "fail_f1": 1,
    "n_test": 1190,
    "train_loss": 2.2387,
    "baseline_accuracy": 99.89
  },
  "conclusion": "success",
  "completed_at": "2026-05-23T11:40:38.570Z"
}
...

=== deepseek_gradient_masking_seed42 ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-23T07:55:20.075Z",
  "updated_at": "2026-05-23T09:47:51.342Z",
  "hypothesis": "Cross-architecture gradient masking validation: DeepSeek-6.7B exception_only with 99.8% gradient masking should achieve \u226598.5% accuracy (vs baseline 99.39%), confirming that content quality (not gradient dilution) explains full_trace degradation across architectures, extending the \u22644% dilution bound beyond Qwen-7B",
  "spec": {
    "command": "bash -c \"... python train/train_sft.py --condition exception_only --model_path deepseek-coder-6.7b-instruct --gradient_mask_ratio 0.998 --gradient_checkpointing --seed 42\"",
    "server": "westd-11235",
    "gpu": [
      "cuda:0"
    ],
    "pid": "867878",
    "log_path": "~/runs/trace-verdict-study/deepseek_gradient_masking_seed42.log",
    "submitted_at": "2026-05-23T07:56:01.348Z",
    "submitted_via": "submit_training_job",
    "backend": "tmux",
    "account": "root",
    "data_path": "/root/autodl-tmp/trace-verdict-study-data/exception_only_train.jsonl",
    "data_count": 4720,
    "model_name": "deepseek-ai/deepseek-coder-6.7b-instruct",
    "seed": 42,
    "checkpoint_source": "trained_from_scratch",
    "eval_data": "/root/autodl-tmp/trace-verdict-study-data/exception_only_test.jsonl",
    "wall_clock_seconds": 6710.0,
    "gpu_hours": 1.86
  },
  "reproduce": {
    "finished_at": "2026-05-23T09:40:03.301Z"
  },
  "extra": {
    "hook_events": [
      {
        "event": "on_complete",
        "action": "agent",
        "ts": "2026-05-23T09:40:08.515903+00:00"
      }
    ]
  },
  "metrics": {
    "accuracy": 0.9933,
    "accuracy_ci_lower": 0.9882,
    "accuracy_ci_upper": 0.9975,
    "pass_precision": 1,
    "pass_recall": 0.9906,
    "pass_f1": 0.9953,
    "fail_precision": 0.9769,
    "fail_recall": 1,
    "fail_f1": 0.9883,
    "eval_loss": 0.0529,
    "train_loss": 0.9961,
    "majority_baseline": 0.715,
    "lift": 0.278
  },
  "conclusion": "success",
 
...
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "268283b4-145a-4e3d-b2e9-9cc558b40e6d"
}
```

</details>

---


### System

_source line 46_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Check baseline data structure",
  "usage": {
    "total_tokens": 22247,
    "tool_uses": 5,
    "duration_ms": 27960
  },
  "last_tool_name": "Bash",
  "uuid": "6bc5aa5a-5932-4157-8987-40f666f1a95c",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 47_

<details open><summary>🔧 Tool call — Bash · `toolu_01SoMfpxpd4KVhBh7ZCemR1v`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\ninner = json.loads(outer['result'])\nexperiments = inner['data']['experiments']\nbaseline = inner['data'].get('baseline', {})\n\n# Check baseline structure\nprint(\"=== BASELINE ===\")\nprint(json.dumps(baseline, indent=2)[:3000])\nPYEOF\n",
  "description": "Check baseline data structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "fa088686-6080-4ea3-94f0-f046add894a0",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_01QswVRxhezoBCgd2BGkTEyY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2306,
      "cache_read_input_tokens": 19701,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2306,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 46,
      "service_tier": "standard",
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

_source line 48 · 2026-05-23T19:18:13.546Z_

<details><summary>↩ Tool result · `toolu_01SoMfpxpd4KVhBh7ZCemR1v`</summary>

```text
=== BASELINE ===
null
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "181ca112-283a-458e-afc1-dcef1f0b7c7a"
}
```

</details>

---


### System

_source line 49_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Inspect key cross_model, regex, calibration, cross_dataset experiments",
  "usage": {
    "total_tokens": 22599,
    "tool_uses": 6,
    "duration_ms": 35421
  },
  "last_tool_name": "Bash",
  "uuid": "90a2592d-4385-4124-89b4-9767a411f725",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 50_

<details open><summary>🔧 Tool call — Bash · `toolu_01VeqPY1n9qPBMwiTq8zbPjm`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\ninner = json.loads(outer['result'])\nexperiments = inner['data']['experiments']\n\n# Look at cross_model, regex, majority, calibration, ablation, density/cross-dataset key experiments\nkey_ids = [\n    'cross_model_calibration', 'cross_model_calibration_eval',\n    'regex_baseline_analysis', 'regex_nomarker_baseline',\n    'majority_baseline' if 'majority_baseline' in experiments else None,\n    'calibration_analysis_seed42',\n    'cross_dataset_batch',\n    'cross_he2mbpp_exception_only_seed42', 'cross_he2mbpp_no_trace_seed42',\n    'cross_mbpp2he_exception_only_seed42', 'cross_mbpp2he_no_trace_seed42',\n    'nomarker_cross_he2mbpp_exception_only',\n]\n\nfor eid in key_ids:\n    if eid and eid in experiments:\n        print(f\"\\n=== {eid} ===\")\n        print(json.dumps(experiments[eid], indent=2))\nPYEOF\n",
  "description": "Inspect key cross_model, regex, calibration, cross_dataset experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "12d0214a-15fa-401e-85c6-c802d442dd83",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_01ApYUuZApVRXxNXcPRvW93h",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 289,
      "cache_read_input_tokens": 22007,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 289,
        "ephemeral_1h_input_tokens": 0
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

_source line 51 · 2026-05-23T19:18:20.999Z_

<details><summary>↩ Tool result · `toolu_01VeqPY1n9qPBMwiTq8zbPjm`</summary>

```text
=== cross_model_calibration ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-21T06:14:12.232Z",
  "updated_at": "2026-05-21T06:14:57.965Z",
  "hypothesis": "Calibration quality (ECE and Brier Score) of exception_only fine-tuned models is universally strong across different model architectures and sizes, not specific to Qwen-7B.",
  "spec": {
    "command": "bash eval/run_cross_model_calibration.sh",
    "server": "westd-11235",
    "data_path": "/root/autodl-tmp/trace-verdict-study-data/exception_only_test.jsonl",
    "data_count": 1190,
    "model_name": "Qwen-7B/Qwen-1.5B/CodeLlama-13B/DeepSeek-6.7B",
    "seed": 42,
    "checkpoint_source": "exception_only checkpoints for all 4 models",
    "eval_data": "exception_only_test.jsonl (1190 samples)",
    "checkpoint_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/cross_model_calibration/",
    "log_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/cross_model_calibration/calibration.log"
  },
  "conclusion": "success",
  "completed_at": "2026-05-21T06:14:57.965Z"
}

=== cross_model_calibration_eval ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-19T21:40:43.958Z",
  "updated_at": "2026-05-19T21:41:10.724Z",
  "hypothesis": "4 \u6a21\u578b \u00d7 exception_only \u7684 ECE/Brier \u5e94\u4e00\u81f4\u6027\u4f4e\uff08ECE < 0.01\uff09\uff0c\u9a8c\u8bc1 calibration quality \u8de8\u6a21\u578b universal",
  "conclusion": "success",
  "metrics": {
    "qwen_7b": {
      "ece": 0.0027,
      "mce": 0.8355,
      "brier": 0.0013,
      "accuracy": 0.9983
    },
    "qwen_1_5b": {
      "ece": 0.002,
      "mce": 0.7549,
      "brier": 0.0013,
      "accuracy": 0.9983
    },
    "codellama_13b": {
      "ece": 0.002,
      "mce": 0.0411,
      "brier": 0.0013,
      "accuracy": 0.9983
    },
    "deepseek_6_7b": {
      "ece": 0.0064,
      "mce": 0.7756,
      "brier": 0.0061,
      "accuracy": 0.9933
    }
  },
  "spec": {
    "checkpoint_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/cross_model_calibration_results.json",
    "log_path": "N/A - eval only",
    "server": "westd-11235",
    "data_path": "existing exception_only checkpoints x4",
    "data_count": 1190,
    "model_name": "4 models x exception_only",
    "seed": 42
  },
  "completed_at": "2026-05-19T21:41:10.724Z"
}

=== regex_baseline_analysis ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-16T03:43:17.799Z",
  "updated_at": "2026-05-16T04:08:29.402Z",
  "hypothesis": "Regex/heuristic baselines on exception_only test data. Tests if simple pattern matching can match SFT performance (Reviewer critical concern).",
  "conclusion": "success",
  "metrics": {
    "regex_B1_ERROR_presence": 0.9345,
    "regex_B2_Traceback": 0.7151,
    "regex_B3_any_keyword": 0.9345,
    "regex_B4_exception_type": 0.9361,
    "regex_B5_format_marker": 0.9933,
    "regex_B6_error_count_ge2": 0.9202,
    "sft_exception_only": 0.9983,
    "best_regex_gap_vs_sft": -0.0622,
    "B5_mcnemar_p": 0.041,
    "n": 1190
  },
  "spec": {
    "checkpoint_path": "N/A (CPU analysis, no model)",
    "log_path": "N/A (CPU analysis)"
  },
  "checkpoint_path": "N/A (analysis-only, no training)",
  "log_path": "N/A (analysis-only, no training)",
  "completed_at": "2026-05-16T04:08:09.296Z"
}

=== regex_nomarker_baseline ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-21T19:03:04.213Z",
  "updated_at": "2026-05-21T19:03:23.905Z",
  "hypothesis": "Regex baselines (B1-B5) on nomarker condition will show significant degradation, especially B5 which relies on the [No exception data in trace] marker. This reveals the marker-condition B5=99.33% is a format artifact, not genuine code reasoning.",
  "conclusion": "success",
  "spec": {
    "command": "python eval/regex_baseline.py on nomarker test data",
    "server": "westd-11235",
    "data_path": "/root/autodl-tmp/trace-verdict-study-data/exception_only_nomarker_test.jsonl",
    "data_count": 1190,
    "model_name": "regex_heuristics",
    "seed": 42,
    "checkpoint_path": "N/A",
    "log_path": "N/A"
  },
  "completed_at": "2026-05-21T19:03:22.128Z",
  "metrics": {
    "B5_marker_acc": 0.9933,
    "B5_nomarker_acc": 0.2849,
    "B5_delta_pp": -70.84,
    "B1_marker_acc": 0.9345,
    "B1_nomarker_acc": 0.7151,
    "B4_marker_acc": 0.9361,
    "B4_nomarker_acc": 0.9361,
    "B5b_nomarker_acc": 0.9345,
    "n": 1190
  }
}

=== calibration_analysis_seed42 ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-15T12:27:04.073Z",
  "updated_at": "2026-05-15T13:09:52.711Z",
  "spec": {
    "plan_id": "plan_007",
    "command": "python eval/calibration_analysis.py",
    "server": "westd-11235",
    "data_path": "/root/autodl-tmp/trace-verdict-study-data/",
    "data_count": 1190,
    "model_name": "Qwen2.5-Coder-7B-Instruct",
    "seed": 42
  },
  "hypothesis": "Calibration analysis: ECE + reliability diagrams for VOTA/exception_only/full_trace/no_trace. Tests whether VOTA's compressed traces improve model calibration beyond accuracy (plan_007).",
  "conclusion": "success",
  "metrics": {
    "no_trace": {
      "ece": 0.171476,
      "mce": 0.475643,
      "brier_score": 0.197152,
      "accuracy": 0.751261,
      "n_samples": 1190
    },
    "full_trace": {
      "ece": 0.095817,
      "mce": 0.249061,
      "brier_score": 0.143924,
      "accuracy": 0.817647,
      "n_samples": 1190
    },
    "label_only": {
      "ece": 0.110686,
      "mce": 0.417124,
      "brier_score": 0.120144,
      "accuracy": 0.862185,
      "n_samples": 1190
    },
    "loop_only": {
      "ece": 0.083085,
      "mce": 0.183406,
      "brier_score": 0.118335,
      "accuracy": 0.856303,
      "n_samples": 1190
    },
    "ae_only": {
      "ece": 0.000415,
      "mce": 0.000415,
      "brier_score": 0.000847,
      "accuracy": 0.99916,
      "n_samples": 1190
    },
    "exception_only": {
      "ece": 0.002717,
      "mce": 0.835484,
      "brier_score": 0.001311,
      "accuracy": 0.998319,
      "n_samples": 1190
    },
    "vota": {
      "ece": 0.00541,
      "mce": 0.622459,
      "brier_score": 0.005234,
      "accuracy": 0.994118,
      "n_samples": 1190
    }
  },
  "checkpoint_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/calibration/",
  "log_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/calibration/calibration_metrics.json",
  "completed_at": "2026-05-15T12:36:49.992Z"
}

=== cross_dataset_batch ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-22T04:34:14.081Z",
  "updated_at": "2026-05-22T06:04:27.930Z",
  "spec": {
    "command": "bash /root/trace-verdict-study/scripts/run_cross_dataset.sh",
    "server": "westd-11235",
    "gpu": [
      "cuda:1"
    ],
    "pid": "745582",
    "log_path": "~/runs/trace-verdict-study/cross_dataset_batch.log",
    "submitted_at": "2026-05-22T04:34:13.600Z",
    "submitted_via": "submit_training_job",
    "backend": "tmux",
    "account": "root",
    "data_path": "/root/autodl-tmp/trace-verdict-study-data/cross_dataset/",
    "data_count": 11820,
    "model_name": "Qwen2.5-Coder-7B-Instruct",
    "seed": 42
  }
}

=== cross_he2mbpp_exception_only_seed42 ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-22T04:33:40.785Z",
  "updated_at": "2026-05-22T06:04:05.530Z",
  "hypothesis": "Cross-dataset generalization HE\u2192MBPP with exception_only: exception trace SFT learns transferable code reasoning patterns that generalize across datasets, predicting smaller accuracy drop compared to no_trace baseline when trained on HumanEval and tested on MBPP.",
  "spec": {
    "command": "/root/miniconda3/bin/python train/train_sft.py --condition cross_he2mbpp_exception_only --data_dir /root/autodl-tmp/trace-verdict-study-data/cross_dataset/ --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/cross_he2mbpp_exception_only --gradient_checkpointing --gpu 0 --seed 42",
    "server": "westd-11235",
    "data_path": "/root/autodl-tmp/trace-verdict-study-data/cross_dataset/",
    "data_count": 1640,
    "model_name": "Qwen2.5-Coder-7B-Instruct",
    "seed": 42
  },
  "checkpoint_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/cross_he2mbpp_exception_only/final",
  "log_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/cross_dataset_batch.log",
  "metrics": {
    "accuracy": 0.9941,
    "pass_precision": 0.998,
    "pass_recall": 0.9936,
    "pass_f1": 0.9957,
    "fail_precision": 0.9858,
    "fail_recall": 0.9955,
    "fail_f1": 0.9906,
    "majority_baseline": 0.6902,
    "lift": 0.304
  },
  "conclusion": "success",
  "completed_at": "2026-05-22T06:04:05.530Z"
}

=== cross_he2mbpp_no_trace_seed42 ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-22T04:33:42.548Z",
  "updated_at": "2026-05-22T06:04:07.456Z",
  "hypothesis": "Cross-dataset generalization HE\u2192MBPP with no_trace baseline: without execution traces, SFT relies on dataset-specific code patterns that do not transfer well across datasets, predicting larger accuracy drop when trained on HumanEval and tested on MBPP.",
  "spec": {
    "command": "/root/miniconda3/bin/python train/train_sft.py --condition cross_he2mbpp_no_trace --data_dir /root/autodl-tmp/trace-verdict-study-data/cross_dataset/ --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/cross_he2mbpp_no_trace --gradient_checkpointing --gpu 0 --seed 42",
    "server": "westd-11235",
    "data_path": "/root/autodl-tmp/trace-verdict-study-data/cross_dataset/",
    "data_count": 1640,
    "model_name": "Qwen2.5-Coder-7B-Instruct",
    "seed": 42
  },
  "checkpoint_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/cross_he2mbpp_no_trace/final",
  "log_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/cross_dataset_batch.log",
  "metrics": {
    "accuracy": 0.7056,
    "pass_precision": 0.736,
    "pass_recall": 0.8941,
    "pass_f1": 0.8074,
    "fail_precision": 0.5478,
    "fail_recall": 0.2857,
    "fail_f1": 0.3756,
    "majority_baseline": 0.6902,
    "lift": 0.0155
  },
  "conclusion": "success",
  "completed_at": "2026-05-22T06:04:07.456Z"
}

=== cross_mbpp2he_exception_only_seed42 ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-22T04:33:45.492Z",
  "updated_at": "2026-05-22T06:03:33.280Z",
  "hypothesis": "Cross-dataset generalization MBPP\u2192HE with exception_only: exception trace SFT learns transferable code reasoning patterns that generalize across datasets, predicting smaller accuracy drop compared to no_trace baseline when trained on MBPP and tested on HumanEval.",
  "spec": {
    "command": "/root/miniconda3/bin/python train/train_sft.py --condition cross_mbpp2he_exception_only --data_dir /root/autodl-tmp/trace-verdict-study-data/cross_dataset/ --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/cross_mbpp2he_exception_only --gradient_checkpointing --gpu 0 --seed 42",
    "server": "westd-11235",
    "data_path": "/root/autodl-tmp/trace-verdict-study-data/cross_dataset/",
    "data_count": 4270,
    "model_name": "Qwen2.5-Coder-7B-Instruct",
    "seed": 42
  }
}

=== cross_mbpp2he_no_trace_seed42 ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-22T04:33:47.580Z",
  "updated_at": "2026-05-22T06:03:35.271Z",
  "hypothesis": "Cross-dataset generalization MBPP\u2192HE with no_trace baseline: without execution traces, SFT relies on dataset-specific code patterns that do not transfer well across datasets, predicting larger accuracy drop when trained on MBPP and tested on HumanEval.",
  "spec": {
    "command": "/root/miniconda3/bin/python train/train_sft.py --condition cross_mbpp2he_no_trace --data_dir /root/autodl-tmp/trace-verdict-study-data/cross_dataset/ --model_path /root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct --output_dir /root/autodl-tmp/trace-verdict-study-checkpoints/cross_mbpp2he_no_trace --gradient_checkpointing --gpu 0 --seed 42",
    "server": "westd-11235",
    "data_path": "/root/autodl-tmp/trace-verdict-study-data/cross_dataset/",
    "data_count": 4270,
    "model_name": "Qwen2.5-Coder-7B-Instruct",
    "seed": 42
  }
}

=== nomarker_cross_he2mbpp_exception_only ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-22T16:57:54.481Z",
  "updated_at": "2026-05-22T17:34:00.548Z",
  "spec": {
    "command": "python train/train_sft.py --condition cross_he2mbpp_exception_only_nomarker",
    "server": "westd-11235",
    "gpu": [
      "cuda:1"
    ],
    "pid": "821073",
    "log_path": "~/runs/trace-verdict-study/nomarker_cross_he2mbpp_exception_only.log",
    "submitted_at": "2026-05-22T16:57:53.985Z",
    "submitted_via": "submit_training_job",
    "backend": "tmux",
    "account": "root",
    "data_path": "/root/autodl-tmp/trace-verdict-study-data/cross_dataset/",
    "data_count": 1640,
    "model_name": "Qwen2.5-Coder-7B-Instruct",
    "seed": 42,
    "checkpoint_source": "trained_from_scratch",
    "eval_data": "cross_he2mbpp_exception_only_nomarker_test.jsonl",
    "wall_clock_seconds": 2166.6,
    "gpu_hours": 0.6
  },
  "reproduce": {
    "finished_at": "2026-05-22T17:24:48.087Z"
  },
  "extra": {
    "hook_events": [
      {
        "event": "on_complete",
        "action": "agent",
        "ts": "2026-05-22T17:24:53.191115+00:00"
      }
    ]
  },
  "hypothesis": "Cross-dataset nomarker ablation: removing format markers from exception_only in the HE\u2192MBPP cross-dataset setting will show minimal accuracy drop (similar to in-distribution ~2pp), confirming that cross-dataset generalization relies on semantic exception content rather than format marker shortcuts.",
  "parent": "cross_he2mbpp_exception_only_seed42",
  "checkpoint_path": "/root/autodl-tmp/trace-verdict-study-checkpoints/nomarker_cross_he2mbpp/final",
  "log_path": "/root/runs/trace-verdict-study/nomarker_cross_he2mbpp_exception_only.log",
  "metrics": {
    "accuracy": 0.9546,
    "pass_precision": 0.9943,
    "pass_recall": 0.9396,
    "pass_f1": 0.9662,
    "fail_precision": 0.8801,
    "fail_recall": 0.9879,
    "fail_f1": 0.9309,
    "eval_loss": 1.09,
    "train_loss": 0.247
  },
  "conclusion": "success",
  "completed_at": "2026-05-22T17:34:00.548Z"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "f994a7cb-59cf-43f3-a949-a85b2359a58a"
}
```

</details>

---


### System

_source line 52_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Inspect main Qwen-7B table experiments",
  "usage": {
    "total_tokens": 29006,
    "tool_uses": 7,
    "duration_ms": 46945
  },
  "last_tool_name": "Bash",
  "uuid": "ce25f801-3509-45b0-ac36-09675bebff16",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 53_

<details open><summary>🔧 Tool call — Bash · `toolu_018Hu1Lu3WEnV7xdraY3fEQG`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\ninner = json.loads(outer['result'])\nexperiments = inner['data']['experiments']\n\n# Look at main table experiments: exception_only, full_trace, no_trace, vota, ae_only, loop_only for Qwen-7B (the base)\nmain_ids = [\n    'exception_only_seed123', 'exception_only_seed456',\n    'full_trace_seed123', 'full_trace_seed42', 'full_trace_seed42_v2', 'full_trace_seed42_v5', 'full_trace_seed456',\n    'no_trace_seed42', 'no_trace_seed123', 'no_trace_seed456',\n    'no_trace_seed42_v2', 'no_trace_seed42_v3', 'no_trace_seed42_v4', 'no_trace_seed42_v5',\n    'vota_seed42', 'vota_seed123', 'vota_seed456',\n    'vota_seed42_v2', 'vota_seed42_v3', 'vota_seed42_v4', 'vota_seed42_v5',\n    'vota_seed456_v2',\n    'ae_only_seed123', 'ae_only_seed456',\n    'loop_only_seed123', 'loop_only_seed456',\n    'label_only_seed123', 'label_only_seed456',\n]\n\nfor eid in main_ids:\n    if eid in experiments:\n        exp = experiments[eid]\n        print(f\"\\n=== {eid} ===\")\n        print(f\"  status: {exp.get('status')}\")\n        print(f\"  metrics: {json.dumps(exp.get('metrics', {}))}\")\n        print(f\"  conclusion: {exp.get('conclusion')}\")\n        tags = exp.get('tags', exp.get('labels', exp.get('tag', exp.get('label', None))))\n        if tags:\n            print(f\"  tags: {tags}\")\nPYEOF\n",
  "description": "Inspect main Qwen-7B table experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "04cf4226-7ee9-4cd4-b94b-bc591630aede",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_01TKvwVnSbmpL5iL4Te4ZDir",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6363,
      "cache_read_input_tokens": 22296,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6363,
        "ephemeral_1h_input_tokens": 0
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

_source line 54 · 2026-05-23T19:18:32.537Z_

<details><summary>↩ Tool result · `toolu_018Hu1Lu3WEnV7xdraY3fEQG`</summary>

```text
=== exception_only_seed123 ===
  status: DONE
  metrics: {"accuracy": 0.9983, "accuracy_ci": [0.9958, 1], "majority_baseline": 0.7151, "lift": 0.2832, "n": 1190, "pass_precision": 1, "pass_recall": 0.9976, "pass_f1": 0.9988, "fail_precision": 0.9941, "fail_recall": 1, "fail_f1": 0.9971, "train_loss": 0.1096, "train_runtime_sec": 7507, "epochs": 3, "seed_comparison": {"seed42_accuracy": 0.9983, "seed456_accuracy": 0.9983, "seed123_accuracy": 0.9983, "max_diff": 0, "note": "identical accuracy to 4 decimal places across all 3 seeds (42/456/123); each has exactly 2/1190 errors; exception_only fully seed-robust"}}
  conclusion: success

=== exception_only_seed456 ===
  status: DONE
  metrics: {"accuracy": 0.9983, "accuracy_ci": [0.9958, 1], "majority_baseline": 0.7151, "lift": 0.2832, "n": 1190, "pass_precision": 1, "pass_recall": 0.9976, "pass_f1": 0.9988, "fail_precision": 0.9941, "fail_recall": 1, "fail_f1": 0.9971, "vs_seed42": {"seed42_accuracy": 0.9983, "seed456_accuracy": 0.9983, "diff": 0, "note": "identical accuracy to 4 decimal places; no predictions.jsonl for paired bootstrap"}, "train_loss": 0.1087, "eval_loss": 0.4629, "train_runtime_sec": 4541, "epochs": 3}
  conclusion: success

=== full_trace_seed123 ===
  status: DONE
  metrics: {"accuracy": 0.7958, "majority_baseline": 0.7151, "lift": 0.0807, "n": 1190, "pass_precision": 0.8753, "pass_recall": 0.8331, "pass_f1": 0.8537, "fail_precision": 0.6263, "fail_recall": 0.7021, "fail_f1": 0.662, "accuracy_ci_lower": 0.7714, "accuracy_ci_upper": 0.8202, "lift_ci_lower": 0.0504, "lift_ci_upper": 0.1143, "train_loss": 0.0416, "eval_loss": 0.0842, "wall_clock_seconds": 7844, "epoch_level": {"epoch_2_eval_loss": 0.0761, "epoch_3_eval_loss": 0.0842}}
  conclusion: success

=== full_trace_seed42 ===
  status: DONE
  metrics: {"train_loss": 0.037, "eval_loss": 0.084, "eval_mean_token_accuracy": 0.984, "accuracy": 0.284, "majority_baseline": 0.7151, "lift": -0.431, "pass_precision": 0.88, "pass_recall": 0.08, "pass_f1": 0.16, "fail_precision": 0.31, "fail_recall": 0.97, "fail_f1": 0.57}
  conclusion: killed

=== full_trace_seed42_v2 ===
  status: DONE
  metrics: {"accuracy": 0.284, "majority_baseline": 0.7151, "lift": -0.4311, "n": 1190, "pass_precision": 0.923, "pass_recall": 0.085, "pass_f1": 0.155, "fail_precision": 0.445, "fail_recall": 0.785, "fail_f1": 0.568, "train_loss": 0.0373, "eval_loss": 0.082, "eval_mean_token_accuracy": 0.984}
  conclusion: negative

=== full_trace_seed42_v5 ===
  status: DONE
  metrics: {"accuracy": 0.8176, "majority_baseline": 0.7151, "lift": 0.1025, "n": 1190, "pass_precision": 0.8774, "pass_recall": 0.866, "pass_f1": 0.8717, "fail_precision": 0.6743, "fail_recall": 0.6962, "fail_f1": 0.6851, "accuracy_ci_lower": 0.797, "accuracy_ci_upper": 0.839, "lift_vs_notrace": 0.0664, "lift_vs_notrace_ci_lower": 0.0437, "lift_vs_notrace_ci_upper": 0.0899, "train_loss": 0.05, "eval_loss": 0.0867, "wall_clock_seconds": 7852, "epoch_level": {"epoch1_accuracy": 0.8303, "epoch2_accuracy": 0.763, "final_accuracy": 0.8176, "trend": "non_monotonic_epoch1_best_epoch2_collapse"}}
  conclusion: success

=== full_trace_seed456 ===
  status: DONE
  metrics: {"accuracy": 0.805, "majority_baseline": 0.7151, "lift": 0.0899, "n": 1190, "pass_precision": 0.8637, "pass_recall": 0.8637, "pass_f1": 0.8637, "fail_precision": 0.6578, "fail_recall": 0.6578, "fail_f1": 0.6578, "accuracy_ci_lower": 0.7824, "accuracy_ci_upper": 0.8269, "lift_ci_lower": 0.0605, "lift_ci_upper": 0.121, "train_loss": 0.0416, "eval_loss": 0.082, "wall_clock_seconds": 7862, "epoch_level": {"epoch_2_eval_loss": 0.0728, "epoch_3_eval_loss": 0.082}}
  conclusion: success

=== no_trace_seed42 ===
  status: DONE
  metrics: {}
  conclusion: killed

=== no_trace_seed123 ===
  status: DONE
  metrics: {"accuracy": 0.7908, "pass_precision": 0.8117, "pass_recall": 0.8971, "pass_f1": 0.8523, "fail_precision": 0.7434, "fail_recall": 0.5901, "fail_f1": 0.6581, "n": 1190}
  conclusion: success

=== no_trace_seed456 ===
  status: DONE
  metrics: {"accuracy": 0.7504, "pass_precision": 0.8805, "pass_recall": 0.7532, "pass_f1": 0.8119, "fail_precision": 0.5455, "fail_recall": 0.7434, "fail_f1": 0.6292, "eval_loss": 0.6092, "train_loss": 0.1781, "n": 1190, "accuracy_ci": [0.7235, 0.7748]}
  conclusion: success

=== no_trace_seed42_v2 ===
  status: DONE
  metrics: {}
  conclusion: killed

=== no_trace_seed42_v3 ===
  status: DONE
  metrics: {"train_loss": 0.18, "eval_loss": 0.645, "eval_mean_token_accuracy": 0.89, "accuracy": 0.7513, "majority_baseline": 0.7151, "lift": 0.0361, "pass_precision": 0.8776, "pass_recall": 0.7579, "pass_f1": 0.8134, "fail_precision": 0.5473, "fail_recall": 0.7345, "fail_f1": 0.6272}
  conclusion: killed

=== no_trace_seed42_v4 ===
  status: DONE
  metrics: {"accuracy": 0.7513, "majority_baseline": 0.7151, "lift": 0.0361, "pass_precision": 0.8776, "pass_recall": 0.7579, "pass_f1": 0.8134, "fail_precision": 0.5473, "fail_recall": 0.7345, "fail_f1": 0.6272, "train_loss": 0.18, "eval_loss": 0.6454, "eval_mean_token_accuracy": 0.8897}
  conclusion: success

=== no_trace_seed42_v5 ===
  status: DONE
  metrics: {"accuracy": 0.7513, "accuracy_ci_lower": 0.7277, "accuracy_ci_upper": 0.7748, "majority_baseline": 0.7151, "lift": 0.0361, "lift_ci_lower": 0.0042, "lift_ci_upper": 0.0706, "n": 1190, "pass_precision": 0.8776, "pass_recall": 0.7579, "pass_f1": 0.8134, "fail_precision": 0.5473, "fail_recall": 0.7345, "fail_f1": 0.6272, "epoch_level": {"epoch1_accuracy": 0.7429, "epoch2_accuracy": 0.763, "final_accuracy": 0.7513, "trend": "non_monotonic_epoch2_best"}}
  conclusion: success

=== vota_seed42 ===
  status: DONE
  metrics: {}
  conclusion: killed

=== vota_seed123 ===
  status: DONE
  metrics: {}
  conclusion: failed

=== vota_seed456 ===
  status: DONE
  metrics: {}
  conclusion: failed

=== vota_seed42_v2 ===
  status: DONE
  metrics: {}
  conclusion: killed

=== vota_seed42_v3 ===
  status: DONE
  metrics: {"train_loss": 0.046, "eval_loss": 0.085, "eval_mean_token_accuracy": 0.983, "accuracy": 0.992, "majority_baseline": 0.7151, "lift": 0.276, "pass_precision": 0.99, "pass_recall": 0.99, "pass_f1": 0.99, "fail_precision": 0.99, "fail_recall": 0.99, "fail_f1": 0.99}
  conclusion: killed

=== vota_seed42_v4 ===
  status: DONE
  metrics: {"accuracy": 0.9563, "majority_baseline": 0.7151, "lift": 0.2412, "n": 1190, "pass_precision": 0.944, "pass_recall": 0.998, "pass_f1": 0.97, "fail_precision": 0.993, "fail_recall": 0.853, "fail_f1": 0.917, "lift_vs_notrace": 0.205, "lift_vs_notrace_ci_lower": 0.177, "lift_vs_notrace_ci_upper": 0.234, "train_loss": 0.046, "eval_loss": 0.0842}
  conclusion: success

=== vota_seed42_v5 ===
  status: DONE
  metrics: {"accuracy": 0.9941, "pass_precision": 1, "pass_recall": 0.9918, "pass_f1": 0.9959, "fail_precision": 0.9798, "fail_recall": 1, "fail_f1": 0.9898, "n": 1190, "tp": 844, "fp": 0, "tn": 339, "fn": 7}
  conclusion: success

=== vota_seed456_v2 ===
  status: DONE
  metrics: {"accuracy": 0.9908, "pass_precision": 1, "pass_recall": 0.987, "pass_f1": 0.993, "fail_precision": 0.969, "fail_recall": 1, "fail_f1": 0.984, "ci_95": [0.985, 0.996]}
  conclusion: success

=== ae_only_seed123 ===
  status: DONE
  metrics: {"accuracy": 0.9908, "n": 1190, "pass_recall": 0.987, "fail_recall": 1, "majority_baseline": 0.7151, "lift": 0.2757}
  conclusion: success

=== ae_only_seed456 ===
  status: DONE
  metrics: {"accuracy": 0.9992, "n": 1190, "majority_baseline": 0.7151, "lift": 0.2841, "seed_comparison": {"seed42_accuracy": 0.9992, "seed123_accuracy": 0.9908, "seed456_accuracy": 0.9992, "mean_accuracy": 0.9964, "std": 0.0049, "note": "2/3 seeds = 99.92%, seed123 = 99.08%. Mean = 99.64% \u00b1 0.49"}}
  conclusion: success

=== loop_only_seed123 ===
  status: DONE
  metrics: {"accuracy": 0.8588, "majority_baseline": 0.7151, "lift": 0.1437, "n": 1190, "pass_precision": 0.9129, "pass_recall": 0.8872, "pass_f1": 0.8999, "fail_precision": 0.7355, "fail_recall": 0.7876, "fail_f1": 0.7607, "accuracy_ci": [0.8403, 0.8773]}
  conclusion: success

=== loop_only_seed456 ===
  status: DONE
  metrics: {"accuracy": 0.8664, "n": 1190, "pass_precision": 0.9179, "pass_recall": 0.8931, "pass_f1": 0.9053, "fail_precision": 0.7486, "fail_recall": 0.7994, "fail_f1": 0.7732, "accuracy_ci": [0.847, 0.884], "seed_comparison": {"seed42_accuracy": 0.8563, "seed123_accuracy": 0.8588, "seed456_accuracy": 0.8664, "mean_accuracy": 0.8605, "std": 0.0053, "note": "3-seed mean = 86.05% \u00b1 0.53%. Moderate variance, seed456 best. loop_only is weakest trace condition (vs exception_only 99.83%, ae_only 99.64%, vota 99.41%)."}}
  conclusion: success

=== label_only_seed123 ===
  status: DONE
  metrics: {"accuracy": 0.8706, "n": 1190, "pass_recall": 0.974, "fail_recall": 0.611, "pass_f1": 0.915, "fail_f1": 0.729}
  conclusion: success

=== label_only_seed456 ===
  status: DONE
  metrics: {"accuracy": 0.859, "n": 1190, "pass_recall": 0.938, "fail_recall": 0.661, "pass_f1": 0.905, "fail_f1": 0.727}
  conclusion: success
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "9945b7cf-358f-4842-96dc-66eebb7bf56b"
}
```

</details>

---


### System

_source line 55_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Inspect VOTA ablation and exception sub-component experiments",
  "usage": {
    "total_tokens": 33783,
    "tool_uses": 8,
    "duration_ms": 57528
  },
  "last_tool_name": "Bash",
  "uuid": "4aa64701-7cfa-444d-bcbf-6895f91a94fe",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 56_

<details open><summary>🔧 Tool call — Bash · `toolu_01PkpxKSCWzDG2BQ45n6zSvu`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\ninner = json.loads(outer['result'])\nexperiments = inner['data']['experiments']\n\n# Look at Qwen-7B seed42 canonical: exception_only, full_trace, no_trace, vota, ae_only, loop_only\n# Also check VOTA multi-component ablation experiments\nvota_ablation = ['vota_ae_only_seed42', 'vota_exception_only_seed42', 'vota_exception_only_seed42_v2',\n                 'vota_loop_only_seed42', 'vota_no_ae_seed42',\n                 'exc_message_only_seed42', 'exc_stacktrace_only_seed42', 'exc_type_only_seed42',\n                 'exception_only_padded2048_seed42', 'full_trace_label_only_seed42']\n\nfor eid in vota_ablation:\n    if eid in experiments:\n        exp = experiments[eid]\n        print(f\"\\n=== {eid} ===\")\n        print(f\"  status: {exp.get('status')}\")\n        print(f\"  hypothesis: {exp.get('hypothesis', '')[:200]}\")\n        print(f\"  metrics: {json.dumps(exp.get('metrics', {}))}\")\n        print(f\"  conclusion: {exp.get('conclusion')}\")\nPYEOF\n",
  "description": "Inspect VOTA ablation and exception sub-component experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "0bcdd336-4f28-4e8a-80a1-6b9c294bd9cc",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_01GgdkGpoVbZmgmdUUAeQ6CY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4733,
      "cache_read_input_tokens": 28659,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4733,
        "ephemeral_1h_input_tokens": 0
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

_source line 57 · 2026-05-23T19:18:43.105Z_

<details><summary>↩ Tool result · `toolu_01PkpxKSCWzDG2BQ45n6zSvu`</summary>

```text
=== vota_ae_only_seed42 ===
  status: DONE
  hypothesis: VOTA component ablation: ae_only condition — only actual/expected values, no exception/loop compression (plan_003 sub-a)
  metrics: {"accuracy": 0.9992, "accuracy_ci": [0.9975, 1], "bootstrap_pairwise": {"ae_only_vs_no_trace": {"diff": 0.2479, "ci": [0.2235, 0.2731], "p_value": 0, "significant": true}, "ae_only_vs_exception_only": {"diff": 0.0008, "ci": [-0.0017, 0.0034], "p_value": 0.8002, "significant": false}, "ae_only_vs_vota": {"diff": 0.005, "ci": [0.0017, 0.0092], "p_value": 0.0046, "significant": true}}, "config": {"n_bootstrap": 10000, "seed": 42, "method": "paired_bootstrap"}}
  conclusion: success

=== vota_exception_only_seed42 ===
  status: DONE
  hypothesis: VOTA component ablation: exception_only condition — only exception summaries, no actual/expected or loop compression. Tests if [ERROR] events are the primary driver of VOTA's 99.2% accuracy (plan_003 
  metrics: {}
  conclusion: failed

=== vota_exception_only_seed42_v2 ===
  status: DONE
  hypothesis: VOTA component ablation: exception_only condition — retry with --gradient_checkpointing (v1 OOM at step 8). Tests if [ERROR] events are the primary driver of VOTA's 99.2% accuracy (plan_003 sub-b)
  metrics: {"accuracy": 0.9983, "majority_baseline": 0.7151, "lift": 0.2832, "n": 1190, "pass_precision": 1, "pass_recall": 0.998, "pass_f1": 0.999, "fail_precision": 0.994, "fail_recall": 1, "fail_f1": 0.997, "lift_vs_notrace": 0.2471, "lift_vs_notrace_ci_lower": 0.2227, "lift_vs_notrace_ci_upper": 0.2714, "lift_vs_fulltrace": 0.1807, "lift_vs_fulltrace_ci_lower": 0.1588, "lift_vs_fulltrace_ci_upper": 0.2034, "lift_vs_vota": 0.0067, "lift_vs_vota_ci_lower": 0.0017, "lift_vs_vota_ci_upper": 0.0126, "lift_vs_vota_pvalue": 0.01}
  conclusion: success

=== vota_loop_only_seed42 ===
  status: DONE
  hypothesis: VOTA component ablation: loop_only condition — only loop compression summaries, no actual/expected or exception. Tests loop behavioral pattern contribution to VOTA 99.2% accuracy (plan_003 sub-c)
  metrics: {"accuracy": 0.8563, "majority_baseline": 0.7151, "lift": 0.1412, "n": 1190, "pass_precision": 0.9239, "pass_recall": 0.8707, "pass_f1": 0.8966, "fail_precision": 0.7165, "fail_recall": 0.8201, "fail_f1": 0.7648, "accuracy_ci": [0.8353, 0.8756], "bootstrap_vs_no_trace": {"diff": 0.105, "ci": [0.0824, 0.1286], "significant": true}, "bootstrap_vs_vota": {"diff": -0.1378, "ci": [-0.1571, -0.1185], "significant": true}, "bootstrap_vs_full_trace": {"diff": 0.0387, "ci": [0.0185, 0.0597], "significant": true}, "train_loss": 0.0718, "wall_clock_seconds": 7425.65}
  conclusion: success

=== vota_no_ae_seed42 ===
  status: DONE
  hypothesis: VOTA without actual/expected values: tests if VOTA's accuracy comes from genuine behavioral understanding vs trivial string comparison (plan_001)
  metrics: {"accuracy": 0.994, "majority_baseline": 0.7151, "lift": 0.279, "n": 1190, "pass_f1": 0.996, "fail_f1": 0.989, "accuracy_ci_lower": 0.989, "accuracy_ci_upper": 0.998, "lift_vs_notrace": 0.243, "lift_vs_notrace_ci_lower": 0.218, "lift_vs_notrace_ci_upper": 0.268, "train_loss": 0.0908, "eval_loss": 0.2215, "wall_clock_seconds": 6397.88}
  conclusion: success

=== exc_message_only_seed42 ===
  status: DONE
  hypothesis: Exception message alone (without type or stacktrace) retains near-perfect diagnostic signal for verdict prediction, because the error message text contains the semantic description of what went wrong
  metrics: {"accuracy": 0.995, "pass_precision": 1, "pass_recall": 0.993, "pass_f1": 0.996, "fail_precision": 0.983, "fail_recall": 1, "fail_f1": 0.991, "n": 1190, "accuracy_ci": [0.991, 0.998]}
  conclusion: success

=== exc_stacktrace_only_seed42 ===
  status: DONE
  hypothesis: Exception stacktrace alone (without exception message) contains sufficient diagnostic signal for near-perfect verdict prediction, because stacktrace structure encodes the causal chain of function call
  metrics: {"accuracy": 0.998, "pass_precision": 1, "pass_recall": 0.998, "pass_f1": 0.999, "fail_precision": 0.994, "fail_recall": 1, "fail_f1": 0.997, "n": 1190, "accuracy_ci": [0.996, 1]}
  conclusion: success

=== exc_type_only_seed42 ===
  status: DONE
  hypothesis: Exception type alone (e.g. 'ValueError') without message or stacktrace retains most of exception_only's diagnostic power, since the error type is the primary signal for verdict classification
  metrics: {}
  conclusion: None

=== exception_only_padded2048_seed42 ===
  status: DONE
  hypothesis: Padding exception-only trace inputs to 2048 tokens maintains high verdict accuracy comparable to unpadded training, validating that fixed-length padding does not degrade the model's ability to classif
  metrics: {"accuracy": 0.9983, "pass_precision": 1, "pass_recall": 0.9976, "pass_f1": 0.9988, "fail_precision": 0.9941, "fail_recall": 1, "fail_f1": 0.9971, "majority_baseline": 0.7151, "lift": 0.2832, "n": 1190}
  conclusion: success

=== full_trace_label_only_seed42 ===
  status: DONE
  hypothesis: Label-only loss on full_trace fixes gradient dilution collapse (plan_002: loss only on pass/fail token, not trace tokens)
  metrics: {"accuracy": 0.8622, "accuracy_ci_lower": 0.8437, "accuracy_ci_upper": 0.8807, "majority_baseline": 0.7151, "lift": 0.1471, "n": 1190, "pass_precision": 0.8821, "pass_recall": 0.9318, "pass_f1": 0.9063, "fail_precision": 0.8007, "fail_recall": 0.6873, "fail_f1": 0.7397, "train_loss": 0.2505, "eval_loss": 0.3205, "lift_vs_notrace": 0.1109, "lift_vs_notrace_ci_lower": 0.0849, "lift_vs_notrace_ci_upper": 0.137, "lift_vs_standard_fulltrace": 0.0445, "lift_vs_standard_fulltrace_ci_lower": 0.0235, "lift_vs_standard_fulltrace_ci_upper": 0.0655, "lift_vs_standard_fulltrace_pvalue": 0}
  conclusion: success
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "10389fd5-82bd-4664-8589-180b1899124f"
}
```

</details>

---


### System

_source line 58_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Inspect Qwen-7B supplementary experiments",
  "usage": {
    "total_tokens": 36570,
    "tool_uses": 9,
    "duration_ms": 68169
  },
  "last_tool_name": "Bash",
  "uuid": "a544e89d-4f5f-4f6a-90d9-17e19f340c7b",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 59_

<details open><summary>🔧 Tool call — Bash · `toolu_01J7aF4Hz8fQnxcEk3zERQFD`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\ninner = json.loads(outer['result'])\nexperiments = inner['data']['experiments']\n\n# Qwen-7B main ablation seed42 canonical\nqwen7b_main = [\n    'qwen7b_full_trace_seed123', 'qwen7b_full_trace_seed456', 'qwen7b_full_trace_seed456_v2',\n    'qwen7b_vota_seed123', 'qwen7b_vota_seed456',\n    'qwen7b_full_trace_label_only_seed123', 'qwen7b_full_trace_label_only_seed456',\n    'gradient_masking_qwen7b_seed42', 'gradient_masking_qwen7b_seed123', 'gradient_masking_qwen7b_seed456',\n    'qwen7b_full_trace_tail512_seed123', 'qwen7b_full_trace_tail512_seed42', 'qwen7b_full_trace_tail512_seed456',\n    'qwen7b_full_trace_head2048_seed42', 'qwen7b_full_trace_tail384_seed42',\n    'qwen7b_exception_only_dynamics_seed42', 'qwen7b_full_trace_dynamics_seed42',\n]\n\nfor eid in qwen7b_main:\n    if eid in experiments:\n        exp = experiments[eid]\n        print(f\"\\n=== {eid} ===\")\n        print(f\"  status: {exp.get('status')}\")\n        print(f\"  hypothesis: {exp.get('hypothesis', '')[:150]}\")\n        print(f\"  metrics: {json.dumps(exp.get('metrics', {}))}\")\n        print(f\"  conclusion: {exp.get('conclusion')}\")\nPYEOF\n",
  "description": "Inspect Qwen-7B supplementary experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "bf50cbb9-79ae-4348-a189-92a84f7fd728",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_01VWGKqdStfsFYFryiH2oaEF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2743,
      "cache_read_input_tokens": 33392,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2743,
        "ephemeral_1h_input_tokens": 0
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

_source line 60 · 2026-05-23T19:18:53.756Z_

<details><summary>↩ Tool result · `toolu_01J7aF4Hz8fQnxcEk3zERQFD`</summary>

```text
=== qwen7b_full_trace_seed123 ===
  status: DONE
  hypothesis: Qwen-7B full_trace seed123 应在 ~81% 附近（与 seed42=81.76% 一致），为 MF-3 multi-seed 要求补齐 full_trace 方差估计。full_trace 是 C2 "more info hurts" claim 的锚点，单 seed 在 
  metrics: {"accuracy": 0.802, "ci_lower": 0.778, "ci_upper": 0.825, "majority_baseline": 0.715, "lift_pp": 8.7, "pass_precision": 0.88, "pass_recall": 0.84, "pass_f1": 0.86, "fail_precision": 0.64, "fail_recall": 0.7, "fail_f1": 0.67, "train_loss": 0.0415, "eval_loss": 0.0827}
  conclusion: success

=== qwen7b_full_trace_seed456 ===
  status: DONE
  hypothesis: Qwen-7B full_trace seed456 应在 ~81% 附近（与 seed42=81.76% 一致），为 MF-3 multi-seed 要求补齐 full_trace 方差估计。3-seed mean 将替换 Table 2 中的单 seed 值。
  metrics: {}
  conclusion: failed

=== qwen7b_full_trace_seed456_v2 ===
  status: DONE
  hypothesis: Qwen-7B full_trace seed456 应在 ~81% 附近（与 seed42=81.76%, seed123=80.20% 一致），为 MF-3 multi-seed 要求补齐 full_trace 方差估计。3-seed mean 将替换 Table 2 中的占位符。
  metrics: {"accuracy": 0.8235, "ci_lower": 0.8017, "ci_upper": 0.8454, "majority_baseline": 0.7151, "lift_pp": 10.84, "pass_precision": 0.8885, "pass_recall": 0.8613, "pass_f1": 0.8747, "fail_precision": 0.6767, "fail_recall": 0.7286, "fail_f1": 0.7017, "train_loss": 0.0416, "eval_loss": 0.0794}
  conclusion: success

=== qwen7b_vota_seed123 ===
  status: DONE
  hypothesis: Qwen-7B VOTA seed123 应在 84-92% 范围（与 vota_seed42_v4 一致），为 N5 reviewer concern 提供 VOTA 条件的方差估计
  metrics: {"accuracy": 0.9866, "accuracy_ci_lower": 0.979, "accuracy_ci_upper": 0.9925, "majority_baseline": 0.7151, "lift": 0.2714, "n": 1190, "pass_precision": 1, "pass_recall": 0.9812, "pass_f1": 0.9905, "fail_precision": 0.9549, "fail_recall": 1, "fail_f1": 0.9769, "train_loss": 0.0499, "eval_loss": 0.0864}
  conclusion: success

=== qwen7b_vota_seed456 ===
  status: DONE
  hypothesis: Qwen-7B VOTA seed456 应在 84-92% 范围（与 vota_seed42_v4 一致），为 N5 reviewer concern 提供 VOTA 条件的方差估计
  metrics: {"accuracy": 0.9908, "accuracy_ci_lower": 0.9849, "accuracy_ci_upper": 0.9958, "majority_baseline": 0.7151, "lift": 0.2756, "n": 1190, "pass_precision": 1, "pass_recall": 0.9871, "pass_f1": 0.9935, "fail_precision": 0.9686, "fail_recall": 1, "fail_f1": 0.984, "train_loss": 0.04969, "eval_loss": 0.08312}
  conclusion: success

=== qwen7b_full_trace_label_only_seed123 ===
  status: DONE
  hypothesis: Qwen-7B full_trace (label_only_loss) seed123 应在 95-98% 范围（与 seed42 一致），为 N5 reviewer concern 提供 full_trace 条件的方差估计
  metrics: {"accuracy": 0.8689, "accuracy_ci_lower": 0.8496, "accuracy_ci_upper": 0.8874, "pass_f1": 0.9121, "fail_f1": 0.7426, "pass_precision": 0.8765, "pass_recall": 0.9506, "fail_precision": 0.8427, "fail_recall": 0.6637, "majority_baseline": 0.7151, "lift": 0.1538, "train_loss": 0.2425, "eval_loss": 0.2787}
  conclusion: success

=== qwen7b_full_trace_label_only_seed456 ===
  status: DONE
  hypothesis: Qwen-7B full_trace (label_only_loss) seed456 应在 95-98% 范围（与 seed42 一致），为 N5 reviewer concern 提供 full_trace 条件的方差估计
  metrics: {"accuracy": 0.847, "accuracy_ci_lower": 0.827, "accuracy_ci_upper": 0.866, "pass_f1": 0.9, "fail_f1": 0.71, "pass_precision": 0.87, "pass_recall": 0.92, "fail_precision": 0.76, "fail_recall": 0.67, "majority_baseline": 0.7151, "lift": 0.1319, "train_loss": 0.2452, "eval_loss": 0.3366}
  conclusion: success

=== gradient_masking_qwen7b_seed42 ===
  status: DONE
  hypothesis: 
  metrics: {}
  conclusion: None

=== gradient_masking_qwen7b_seed123 ===
  status: DONE
  hypothesis: Gradient masking (keeping only top 0.2% gradient signals) on exception_only condition with seed 123 achieves comparable accuracy to seed 42 (98.99%), 
  metrics: {"accuracy": 0.9933, "pass_precision": 1, "pass_recall": 0.9906, "pass_f1": 0.9953, "fail_precision": 0.9769, "fail_recall": 1, "fail_f1": 0.9883, "n": 1190, "accuracy_ci": [0.9882, 0.9975], "majority_baseline": 0.7151, "lift": 0.2782}
  conclusion: success

=== gradient_masking_qwen7b_seed456 ===
  status: DONE
  hypothesis: Gradient masking seed robustness (seed 456): gradient masking (keeping only top 0.2% gradient signals) on exception_only condition achieves comparable
  metrics: {"accuracy": 0.9933, "pass_precision": 1, "pass_recall": 0.9906, "pass_f1": 0.9953, "fail_precision": 0.9769, "fail_recall": 1, "fail_f1": 0.9883, "n": 1190, "accuracy_ci": [0.9882, 0.9975], "majority_baseline": 0.7151, "lift": 0.2782, "eval_loss": 0.0381, "train_loss": 1.6031}
  conclusion: success

=== qwen7b_full_trace_tail512_seed123 ===
  status: DONE
  hypothesis: Qwen-7B tail-512 seed123 应在 93-97% range（与 full_trace_tail_512_seed42=93.6% 一致），验证 phase transition 后 convergence band 的 seed robustness
  metrics: {"accuracy": 0.9597, "accuracy_ci_lower": 0.9487, "accuracy_ci_upper": 0.9706, "majority_baseline": 0.7151, "lift": 0.2445, "n": 1190, "pass_precision": 0.9751, "pass_recall": 0.9683, "pass_f1": 0.9717, "fail_precision": 0.9217, "fail_recall": 0.9381, "fail_f1": 0.9298, "seed_comparison": {"seed42_accuracy": 0.936, "seed123_accuracy": 0.9597}}
  conclusion: success

=== qwen7b_full_trace_tail512_seed42 ===
  status: DONE
  hypothesis: Qwen-7B tail-512 (硬截断 full_trace_tail_512) 应与原 full_trace_tail seed42 结果 (~93.6%) 接近，确认 condition 差异不影响 budget curve 结论；同时为 cross-seed 提供可比 baseline
  metrics: {}
  conclusion: failed

=== qwen7b_full_trace_tail512_seed456 ===
  status: DONE
  hypothesis: Qwen-7B tail-512 seed456 应在 93-97% range（与 full_trace_tail_512_seed42=93.6% 一致），验证 phase transition 后 convergence band 的 seed robustness
  metrics: {"accuracy": 0.9765, "majority_baseline": 0.7151, "lift": 0.2613, "n": 1190, "pass_precision": 0.9746, "pass_recall": 0.9929, "pass_f1": 0.9837, "fail_precision": 0.9814, "fail_recall": 0.9351, "fail_f1": 0.9577, "accuracy_ci": [0.9681, 0.9849]}
  conclusion: success

=== qwen7b_full_trace_head2048_seed42 ===
  status: DONE
  hypothesis: Qwen-7B head-2048 应在 75-82% (signal-poor convergence band)，与其他 3 模型 head-2048 (75.3-79.9%) 对齐，补全 4 模型 head-tail gap claim
  metrics: {"accuracy_epoch1": 0.816, "accuracy_epoch3": 0.81, "pass_f1_epoch1": 0.87, "fail_f1_epoch1": 0.686, "pass_f1_epoch3": 0.866, "fail_f1_epoch3": 0.674, "best_accuracy": 0.816, "best_epoch": 1}
  conclusion: success

=== qwen7b_full_trace_tail384_seed42 ===
  status: DONE
  hypothesis: Qwen-7B tail-384 应在 85-93% 之间（256→512 phase transition 的中间点），精确定位 phase transition 曲线形状
  metrics: {"accuracy": 0.798, "accuracy_ci_lower": 0.776, "accuracy_ci_upper": 0.821, "majority_baseline": 0.715, "lift": 0.083, "n": 1190, "pass_precision": 0.89, "pass_recall": 0.82, "pass_f1": 0.85, "fail_precision": 0.62, "fail_recall": 0.75, "fail_f1": 0.68}
  conclusion: success

=== qwen7b_exception_only_dynamics_seed42 ===
  status: DONE
  hypothesis: exception_only 因 information density 更高，收敛速度应显著快于 full_trace（即使 full_trace 用 label_only_loss）。通过每 50 steps eval 记录 learning curve 验证。
  metrics: {"step50_acc": 0.9933, "step100_acc": 0.9933, "step150_acc": 0.9933, "step200_acc": 0.9983, "step250_acc": 0.9983, "step300_acc": 0.9983, "step350_acc": 0.9983, "step400_acc": 0.9983, "step444_acc": 0.9983, "saturation_step": 200, "final_loss": 0.0329, "pass_f1": 0.9988, "fail_f1": 0.9971}
  conclusion: success

=== qwen7b_full_trace_dynamics_seed42 ===
  status: DONE
  hypothesis: full_trace (label_only_loss) 收敛速度应慢于 exception_only，因 trace 中冗余信息稀释了有效 signal density。通过每 50 steps eval 记录 learning curve 验证。
  metrics: {"step50_acc": 0.8739, "step100_acc": 0.821, "step150_acc": 0.8571, "step200_acc": 0.8655, "step250_acc": 0.8739, "step300_acc": 0.8487, "step350_acc": 0.8882, "step400_acc": 0.8571, "step444_acc": 0.8824, "best_step": 350, "best_acc": 0.8882, "final_loss": 0.0085}
  conclusion: success
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "d8245601-4060-4bd9-8f01-8c156f980415"
}
```

</details>

---


### System

_source line 61_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Extract metrics for cross-model experiments (DeepSeek, Qwen-1.5B, CodeLlama)",
  "usage": {
    "total_tokens": 40825,
    "tool_uses": 10,
    "duration_ms": 86944
  },
  "last_tool_name": "Bash",
  "uuid": "3c9b2a08-83cb-4e73-800b-22060c4a793d",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 62_

<details open><summary>🔧 Tool call — Bash · `toolu_01Mz7V1CuGMJqYspjbSvQLs2`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\ninner = json.loads(outer['result'])\nexperiments = inner['data']['experiments']\n\n# DeepSeek and Qwen-1.5B and CodeLlama cross-model experiments\ncross_model_ids = [\n    'deepseek_exception_only_seed42', 'deepseek_exception_only_seed123', 'deepseek_exception_only_seed123_v2',\n    'deepseek_exception_only_seed456',\n    'deepseek_full_trace_seed42', 'deepseek_full_trace_seed42_v2', 'deepseek_full_trace_seed42_v3',\n    'deepseek_full_trace_tail512_seed42', 'deepseek_full_trace_tail512_seed123', 'deepseek_full_trace_tail512_seed123_v2', \n    'deepseek_full_trace_tail512_seed456',\n    'deepseek_no_trace_seed42', 'deepseek_no_trace_seed123',\n    'deepseek_vota_seed42', 'deepseek_vota_seed123', 'deepseek_vota_seed456',\n    'deepseek_ae_only_seed42', 'deepseek_ae_only_seed123',\n    'deepseek_loop_only_seed42', 'deepseek_loop_only_seed123', 'deepseek_loop_only_seed456',\n    'deepseek_label_only_seed42',\n    # CodeLlama\n    'codellama13b_exception_only_seed42', 'codellama13b_exception_only_seed123', 'codellama13b_exception_only_seed456',\n    'codellama13b_full_trace_tail512_seed42', 'codellama13b_full_trace_tail512_seed123', 'codellama13b_full_trace_tail512_seed456',\n    'codellama13b_full_trace_tail1024_seed42', 'codellama13b_full_trace_tail2048_seed42',\n    'codellama13b_no_trace_seed42',\n    'codellama13b_vota_seed42', 'codellama13b_vota_seed123',\n    'codellama13b_ae_only_seed42', 'codellama13b_ae_only_seed123',\n    'codellama13b_loop_only_seed42', 'codellama13b_loop_only_seed123', 'codellama13b_loop_only_seed456',\n    'codellama13b_label_only_seed42', 'codellama13b_label_only_seed42_v2', 'codellama13b_label_only_seed123_v2',\n    # Qwen-1.5B\n    'qwen15b_exception_only_seed42', 'qwen15b_exception_only_seed123', 'qwen15b_exception_only_seed123_v2',\n    'qwen15b_exception_only_seed456',\n    'qwen15b_full_trace_seed42',\n    'qwen15b_full_trace_tail512_seed42', 'qwen15b_full_trace_tail512_seed123', 'qwen15b_full_trace_tail512_seed456',\n    'qwen15b_no_trace_seed42', 'qwen15b_no_trace_seed123', 'qwen15b_no_trace_seed456',\n    'qwen15b_vota_seed42', 'qwen15b_vota_seed123',\n    'qwen15b_ae_only_seed42', 'qwen15b_ae_only_seed123',\n    'qwen15b_loop_only_seed42', 'qwen15b_loop_only_seed123', 'qwen15b_loop_only_seed456',\n    'qwen15b_label_only_seed42', 'qwen15b_label_only_seed42_v2', 'qwen15b_label_only_seed123_v2', 'qwen15b_label_only_seed456_v2',\n]\n\nfor eid in cross_model_ids:\n    if eid in experiments:\n        exp = experiments[eid]\n        print(f\"\\n=== {eid} ===\")\n        print(f\"  status: {exp.get('status')}\")\n        m = exp.get('metrics', {})\n        # Only print key metrics\n        key_metrics = {k: v for k, v in m.items() if k in [\n            'accuracy', 'accuracy_ci', 'accuracy_ci_lower', 'accuracy_ci_upper', 'ci_lower', 'ci_upper', 'ci_95',\n            'majority_baseline', 'lift', 'n', 'pass_f1', 'fail_f1', 'seed_comparison', 'mean_accuracy', 'std'\n        ]}\n        print(f\"  key_metrics: {json.dumps(key_metrics)}\")\n        print(f\"  conclusion: {exp.get('conclusion')}\")\nPYEOF\n",
  "description": "Extract metrics for cross-model experiments (DeepSeek, Qwen-1.5B, CodeLlama)"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "7e5723cc-3cec-4997-9007-a22aee3ef618",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_01EJSeCafo8j5xWQwkfS3vJd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4209,
      "cache_read_input_tokens": 36135,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4209,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 46,
      "service_tier": "standard",
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

_source line 63 · 2026-05-23T19:19:12.575Z_

<details><summary>↩ Tool result · `toolu_01Mz7V1CuGMJqYspjbSvQLs2`</summary>

```text
=== deepseek_exception_only_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.9933, "majority_baseline": 0.7151, "lift": 0.2782, "n": 1190, "pass_f1": 0.9953, "fail_f1": 0.9883}
  conclusion: success

=== deepseek_exception_only_seed123 ===
  status: DONE
  key_metrics: {}
  conclusion: killed

=== deepseek_exception_only_seed123_v2 ===
  status: DONE
  key_metrics: {"accuracy": 0.995}
  conclusion: success

=== deepseek_exception_only_seed456 ===
  status: DONE
  key_metrics: {"accuracy": 0.9933, "majority_baseline": 0.7151, "lift": 0.2782, "n": 1190, "pass_f1": 0.9953, "fail_f1": 0.9883, "accuracy_ci": [0.9882, 0.9975], "seed_comparison": {"seed42_accuracy": 0.9933, "seed456_accuracy": 0.9933, "seed123_accuracy": 0.9109, "note": "seed42 and seed456 identical (99.33%); seed123 outlier (91.09%). 2/3 seeds robust."}}
  conclusion: success

=== deepseek_full_trace_seed42 ===
  status: DONE
  key_metrics: {"majority_baseline": 0.7151, "n": 1190}
  conclusion: negative

=== deepseek_full_trace_seed42_v2 ===
  status: DONE
  key_metrics: {}
  conclusion: killed

=== deepseek_full_trace_seed42_v3 ===
  status: DONE
  key_metrics: {"accuracy": 0.7916, "majority_baseline": 0.7151, "lift": 0.0765, "n": 1190, "pass_f1": 0.854, "fail_f1": 0.637, "accuracy_ci": [0.768, 0.813]}
  conclusion: success

=== deepseek_full_trace_tail512_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.939, "accuracy_ci_lower": 0.926, "accuracy_ci_upper": 0.953, "majority_baseline": 0.715, "pass_f1": 0.96, "fail_f1": 0.9}
  conclusion: success

=== deepseek_full_trace_tail512_seed123 ===
  status: DONE
  key_metrics: {"seed_comparison": {"seed42_accuracy": 0.9361, "seed123_accuracy": "N/A - OOM crash"}}
  conclusion: failed

=== deepseek_full_trace_tail512_seed123_v2 ===
  status: DONE
  key_metrics: {"accuracy": 0.9504, "majority_baseline": 0.7151, "lift": 0.2353, "n": 1190, "pass_f1": 0.9649, "fail_f1": 0.9154, "accuracy_ci": [0.9387, 0.963]}
  conclusion: success

=== deepseek_full_trace_tail512_seed456 ===
  status: DONE
  key_metrics: {"accuracy": 0.9605, "accuracy_ci_lower": 0.9496, "accuracy_ci_upper": 0.9714, "majority_baseline": 0.7151, "lift": 0.2454, "n": 1190, "pass_f1": 0.9723, "fail_f1": 0.9312, "seed_comparison": {"seed42_accuracy": 0.9361, "seed456_accuracy": 0.9605}}
  conclusion: success

=== deepseek_no_trace_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.7336, "majority_baseline": 0.7151, "lift": 0.0185, "n": 1190, "pass_f1": 0.813, "fail_f1": 0.539, "accuracy_ci": [0.708, 0.757]}
  conclusion: negative

=== deepseek_no_trace_seed123 ===
  status: DONE
  key_metrics: {}
  conclusion: killed

=== deepseek_vota_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.8445, "majority_baseline": 0.7151, "lift": 0.1294, "accuracy_ci": [0.826, 0.864], "pass_f1": 0.902, "fail_f1": 0.625}
  conclusion: success

=== deepseek_vota_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.9916, "accuracy_ci_lower": 0.9857, "accuracy_ci_upper": 0.9966}
  conclusion: success

=== deepseek_vota_seed456 ===
  status: DONE
  key_metrics: {"accuracy": 0.9933}
  conclusion: success

=== deepseek_ae_only_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.9874, "accuracy_ci_lower": 0.9807, "accuracy_ci_upper": 0.9933, "fail_f1": 0.977, "pass_f1": 0.991}
  conclusion: success

=== deepseek_ae_only_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.9832}
  conclusion: success

=== deepseek_loop_only_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.8126, "accuracy_ci_lower": 0.7908, "accuracy_ci_upper": 0.8345}
  conclusion: success

=== deepseek_loop_only_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.8126, "accuracy_ci_lower": 0.792, "accuracy_ci_upper": 0.834}
  conclusion: success

=== deepseek_loop_only_seed456 ===
  status: DONE
  key_metrics: {"accuracy": 0.784, "majority_baseline": 0.715, "fail_f1": 0.63}
  conclusion: success

=== deepseek_label_only_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.285, "accuracy_ci_lower": 0.261, "accuracy_ci_upper": 0.308, "majority_baseline": 0.7151, "lift": -0.43, "pass_f1": 0, "fail_f1": 0.44}
  conclusion: negative

=== codellama13b_exception_only_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.9983, "accuracy_ci_lower": 0.9958, "accuracy_ci_upper": 1, "pass_f1": 0.9988, "fail_f1": 0.9971}
  conclusion: success

=== codellama13b_exception_only_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 1, "n": 1190, "pass_f1": 1, "fail_f1": 1}
  conclusion: success

=== codellama13b_exception_only_seed456 ===
  status: DONE
  key_metrics: {"accuracy": 0.9983, "n": 1190, "pass_f1": 0.9988, "fail_f1": 0.9971}
  conclusion: success

=== codellama13b_full_trace_tail512_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.9824, "accuracy_ci_lower": 0.9748, "accuracy_ci_upper": 0.9899, "majority_baseline": 0.7151, "lift": 0.2672, "n": 1190, "pass_f1": 0.9878, "fail_f1": 0.968}
  conclusion: success

=== codellama13b_full_trace_tail512_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.9824, "accuracy_ci_lower": 0.9748, "accuracy_ci_upper": 0.9899, "majority_baseline": 0.7151, "lift": 0.2672, "n": 1190, "pass_f1": 0.9878, "fail_f1": 0.968, "seed_comparison": {"seed42_accuracy": 0.975, "seed123_accuracy": 0.9824, "diff": 0.0074, "note": "seed123 (98.24%) slightly exceeds seed42 (97.5%); both well above 97% \u2014 CodeLlama-13B tail-512 seed-robust"}}
  conclusion: success

=== codellama13b_full_trace_tail512_seed456 ===
  status: DONE
  key_metrics: {"accuracy": 0.9824, "accuracy_ci_lower": 0.9748, "accuracy_ci_upper": 0.9899, "majority_baseline": 0.7151, "lift": 0.2672, "n": 1190, "pass_f1": 0.9878, "fail_f1": 0.968, "seed_comparison": {"seed42_previous": 0.975, "seed123_accuracy": 0.9824, "seed456_accuracy": 0.9824}}
  conclusion: success

=== codellama13b_full_trace_tail1024_seed42 ===
  status: DONE
  key_metrics: {}
  conclusion: failed

=== codellama13b_full_trace_tail2048_seed42 ===
  status: DONE
  key_metrics: {}
  conclusion: failed

=== codellama13b_no_trace_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.765, "n": 1190, "majority_baseline": 0.7151, "lift": 0.05, "pass_f1": 0.84, "fail_f1": 0.59, "accuracy_ci_lower": 0.738, "accuracy_ci_upper": 0.787}
  conclusion: success

=== codellama13b_vota_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.9857, "accuracy_ci_lower": 0.979, "accuracy_ci_upper": 0.9916, "pass_f1": 0.99, "fail_f1": 0.9748}
  conclusion: success

=== codellama13b_vota_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.9891, "accuracy_ci": [0.9832, 0.9941], "pass_f1": 0.9924, "fail_f1": 0.9809, "n": 1190, "majority_baseline": 0.7151, "lift": 0.2739}
  conclusion: success

=== codellama13b_ae_only_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.9908, "accuracy_ci_lower": 0.9849, "accuracy_ci_upper": 0.9958, "pass_f1": 0.9935, "fail_f1": 0.984, "majority_baseline": 0.7151}
  conclusion: success

=== codellama13b_ae_only_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.9908, "accuracy_ci_lower": 0.9849, "accuracy_ci_upper": 0.9958, "pass_f1": 0.993, "fail_f1": 0.984}
  conclusion: success

=== codellama13b_loop_only_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.7706, "accuracy_ci_lower": 0.7487, "accuracy_ci_upper": 0.7941, "n": 1190, "majority_baseline": 0.7151, "lift": 0.0555, "pass_f1": 0.82, "fail_f1": 0.67}
  conclusion: negative

=== codellama13b_loop_only_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.7605, "accuracy_ci_lower": 0.7387, "accuracy_ci_upper": 0.7857, "pass_f1": 0.8078, "fail_f1": 0.6823, "majority_baseline": 0.7151, "lift": 0.0454, "n": 1190}
  conclusion: success

=== codellama13b_loop_only_seed456 ===
  status: DONE
  key_metrics: {"accuracy": 0.7908, "majority_baseline": 0.7151, "lift": 0.0757, "pass_f1": 0.843, "fail_f1": 0.688, "n": 1190}
  conclusion: success

=== codellama13b_label_only_seed42 ===
  status: DONE
  key_metrics: {}
  conclusion: killed

=== codellama13b_label_only_seed42_v2 ===
  status: DONE
  key_metrics: {"accuracy": 0.2849, "accuracy_ci_lower": 0.2613, "accuracy_ci_upper": 0.3084, "majority_baseline": 0.7151, "pass_f1": 0, "fail_f1": 0.4434}
  conclusion: negative

=== codellama13b_label_only_seed123_v2 ===
  status: DONE
  key_metrics: {"accuracy": "collapsed"}
  conclusion: success

=== qwen15b_exception_only_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.9983, "accuracy_ci_lower": 0.9958, "accuracy_ci_upper": 1, "majority_baseline": 0.7151, "lift": 0.283, "n": 1190, "pass_f1": 0.9988, "fail_f1": 0.9971}
  conclusion: success

=== qwen15b_exception_only_seed123 ===
  status: DONE
  key_metrics: {"seed_comparison": {"seed42_accuracy": 0.9983, "seed123_accuracy": "N/A - OOM crash"}}
  conclusion: failed

=== qwen15b_exception_only_seed123_v2 ===
  status: DONE
  key_metrics: {"accuracy": 0.9983, "accuracy_ci_lower": 0.9958, "accuracy_ci_upper": 1, "seed_comparison": {"seed42_accuracy": 0.9983, "seed456_accuracy": 0.9983, "seed123_accuracy": 0.9983}}
  conclusion: success

=== qwen15b_exception_only_seed456 ===
  status: DONE
  key_metrics: {"accuracy": 0.9983, "accuracy_ci_lower": 0.9958, "accuracy_ci_upper": 1, "majority_baseline": 0.7151, "lift": 0.2832, "n": 1190, "pass_f1": 0.9988, "fail_f1": 0.9971, "seed_comparison": {"seed42_accuracy": 0.9983, "seed456_accuracy": 0.9983, "diff": 0, "note": "Identical to seed42 to 4 decimal places \u2014 exception_only fully seed-robust on Qwen-1.5B"}}
  conclusion: success

=== qwen15b_full_trace_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.7706, "n": 1190}
  conclusion: success

=== qwen15b_full_trace_tail512_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.956, "accuracy_ci_lower": 0.945, "accuracy_ci_upper": 0.968, "majority_baseline": 0.715, "pass_f1": 0.97, "fail_f1": 0.92}
  conclusion: success

=== qwen15b_full_trace_tail512_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.9765, "accuracy_ci_lower": 0.9681, "accuracy_ci_upper": 0.9849, "majority_baseline": 0.7151, "lift": 0.2613, "n": 1190, "pass_f1": 0.9837, "fail_f1": 0.9578, "seed_comparison": {"seed42_accuracy": 0.956, "seed123_accuracy": 0.9765, "note": "seed123 (97.65%) exceeds seed42 (95.6%) by 2pp; both in convergence band post-phase-transition"}}
  conclusion: success

=== qwen15b_full_trace_tail512_seed456 ===
  status: DONE
  key_metrics: {"accuracy": 0.9672, "accuracy_ci_lower": 0.9563, "accuracy_ci_upper": 0.9773, "majority_baseline": 0.7151, "lift": 0.2521, "n": 1190, "pass_f1": 0.9771, "fail_f1": 0.9424, "seed_comparison": {"seed42_accuracy": 0.956, "seed123_accuracy": 0.9765, "seed456_accuracy": 0.9672, "note": "seed456 (96.72%) within convergence band [95.6%, 97.65%], confirming seed robustness post-phase-transition"}}
  conclusion: success

=== qwen15b_no_trace_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.6731, "n": 1190, "pass_f1": 0.7527, "fail_f1": 0.518}
  conclusion: success

=== qwen15b_no_trace_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.7588, "accuracy_ci_lower": 0.7328, "accuracy_ci_upper": 0.7824, "majority_baseline": 0.7151, "lift": 0.0437, "pass_f1": 0.8323, "fail_f1": 0.571}
  conclusion: success

=== qwen15b_no_trace_seed456 ===
  status: DONE
  key_metrics: {"accuracy": 0.7387, "fail_f1": 0.5266, "pass_f1": 0.8195}
  conclusion: success

=== qwen15b_vota_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.9958, "n": 1190, "pass_f1": 0.9971, "fail_f1": 0.9926}
  conclusion: success

=== qwen15b_vota_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.995, "ci_95": [0.9908, 0.9983], "pass_f1": 0.9965, "fail_f1": 0.9912}
  conclusion: success

=== qwen15b_ae_only_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.9908, "majority_baseline": 0.7151, "lift": 0.2756, "pass_f1": 0.9935, "fail_f1": 0.984, "n": 1190, "accuracy_ci_lower": 0.9849, "accuracy_ci_upper": 0.9958}
  conclusion: success

=== qwen15b_ae_only_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.9857, "majority_baseline": 0.715, "fail_f1": 0.975}
  conclusion: success

=== qwen15b_loop_only_seed42 ===
  status: DONE
  key_metrics: {"accuracy": 0.7832, "pass_f1": 0.8526, "fail_f1": 0.5905}
  conclusion: success

=== qwen15b_loop_only_seed123 ===
  status: DONE
  key_metrics: {"accuracy": 0.8109, "pass_f1": 0.8737, "fail_f1": 0.6244}
  conclusion: success

=== qwen15b_loop_only_seed456 ===
  status: DONE
  key_metrics: {"accuracy": 0.792, "ci_95": [0.768, 0.813], "majority_baseline": 0.715, "pass_f1": 0.86, "fail_f1": 0.63}
  conclusion: success

=== qwen15b_label_only_seed42 ===
  status: DONE
  key_metrics: {}
  conclusion: killed

=== qwen15b_label_only_seed42_v2 ===
  status: DONE
  key_metrics: {"accuracy": 0.789, "accuracy_ci_lower": 0.766, "accuracy_ci_upper": 0.812, "majority_baseline": 0.715, "pass_f1": 0.86, "fail_f1": 0.57}
  conclusion: success

=== qwen15b_label_only_seed123_v2 ===
  status: DONE
  key_metrics: {"accuracy": 0.8134, "accuracy_ci_lower": 0.7924, "accuracy_ci_upper": 0.8345, "majority_baseline": 0.7151, "pass_f1": 0.878, "fail_f1": 0.602}
  conclusion: success

=== qwen15b_label_only_seed456_v2 ===
  status: DONE
  key_metrics: {"accuracy": 0.8252, "pass_f1": 0.885, "fail_f1": 0.639, "majority_baseline": 0.715}
  conclusion: success
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "f6a58bed-1757-4556-b756-7e85ac0be9c6"
}
```

</details>

---


### System

_source line 64_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Extract remaining experiments including nomarker, trace length, fewshot, debugbench",
  "usage": {
    "total_tokens": 48152,
    "tool_uses": 11,
    "duration_ms": 107628
  },
  "last_tool_name": "Bash",
  "uuid": "20ded832-f9cf-456e-b88b-ab18a32d730b",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 65_

<details open><summary>🔧 Tool call — Bash · `toolu_015S8aP4Rp3MbDrJYtczmKW8`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\ninner = json.loads(outer['result'])\nexperiments = inner['data']['experiments']\n\n# nomarker experiments, ablation density/trace length, debugbench, fewshot, attention analysis\nremaining_ids = [\n    'exception_only_nomarker_seed42', 'exception_only_nomarker_seed123', 'exception_only_nomarker_seed456',\n    'codellama13b_nomarker_seed42', 'qwen15b_nomarker_seed42',\n    # trace length ablations (Qwen-7B)\n    'full_trace_256tok_seed42', 'full_trace_512tok_seed42', 'full_trace_1024tok_seed42', 'full_trace_2048tok_seed42',\n    'full_trace_tail256_seed42', 'full_trace_tail_256_seed42', 'full_trace_tail_512_seed42', 'full_trace_tail_1024_seed42',\n    'full_trace_tail_seed42', 'full_trace_tail256_seed42',\n    'deepseek_full_trace_tail256_seed42', 'deepseek_full_trace_tail384_seed42', \n    'deepseek_full_trace_tail1024_seed42', 'deepseek_full_trace_tail2048_seed42', 'deepseek_full_trace_head2048_seed42',\n    'codellama13b_full_trace_tail256_seed42', 'codellama13b_full_trace_tail384_seed42',\n    'codellama13b_full_trace_tail2048_seed42', 'codellama13b_full_trace_tail2048_seed42_v2', 'codellama13b_full_trace_tail2048_seed42_v3',\n    'codellama13b_full_trace_tail1024_seed42', 'codellama13b_full_trace_tail1024_seed42_v2', 'codellama13b_full_trace_tail1024_seed42_v3',\n    'codellama13b_full_trace_head2048_seed42',\n    'qwen15b_full_trace_tail256_seed42', 'qwen15b_full_trace_tail384_seed42',\n    'qwen15b_full_trace_tail1024_seed42', 'qwen15b_full_trace_tail2048_seed42', 'qwen15b_full_trace_head2048_seed42',\n    # debugbench, fewshot\n    'debugbench_exception_only_seed42', 'debugbench_no_trace_seed42', 'debugbench_vota_seed42', 'debugbench_exception_bug_fix',\n    'fewshot_gpt4o_exception_only_0shot', 'fewshot_gpt4o_exception_only_3shot', 'fewshot_gpt4o_no_trace_0shot',\n    'fewshot_gpt41_exception_only_0shot', 'fewshot_gpt41_exception_only_3shot', 'fewshot_gpt41_no_trace_0shot',\n    'fewshot_qwen7b_exception_only',\n    # attention / misc\n    'attention_gradient_analysis',\n    'zeroshot_codellama13b_exception_only', 'zeroshot_deepseek7b_exception_only',\n    'zeroshot_qwen15b_exception_only', 'zeroshot_qwen7b_exception_only',\n    'qwen1.5b_exception_only_seed42', 'qwen1.5b_full_trace_seed42', 'qwen1.5b_no_trace_seed42', 'qwen1.5b_vota_seed42',\n    'codellama_exception_only_seed42', 'codellama_no_trace_seed42', 'codellama_vota_seed42',\n    'eval_missing_predictions_batch', 'eval_missing_predictions_batch_v2',\n]\n\nfor eid in remaining_ids:\n    if eid in experiments:\n        exp = experiments[eid]\n        print(f\"\\n=== {eid} ===\")\n        print(f\"  status: {exp.get('status')}\")\n        print(f\"  hypothesis: {exp.get('hypothesis', '')[:150]}\")\n        print(f\"  metrics: {json.dumps(exp.get('metrics', {}))}\")\n        print(f\"  conclusion: {exp.get('conclusion')}\")\nPYEOF\n",
  "description": "Extract remaining experiments including nomarker, trace length, fewshot, debugbench"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "6116341e-1965-4fac-aa1b-800f99e99650",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_018EV7oMzVL7kNynSMPRBqh2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7281,
      "cache_read_input_tokens": 40344,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7281,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 46,
      "service_tier": "standard",
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

_source line 66 · 2026-05-23T19:19:33.223Z_

<details><summary>↩ Tool result · `toolu_015S8aP4Rp3MbDrJYtczmKW8`</summary>

```text
=== exception_only_nomarker_seed42 ===
  status: DONE
  hypothesis: Format marker ablation: removing [No exception data in trace] and [ERROR] prefix markers reduces accuracy by ~2pp, isolating semantic content contribu
  metrics: {"accuracy": 0.9655, "n": 1190, "accuracy_ci": [0.955, 0.976]}
  conclusion: success

=== exception_only_nomarker_seed123 ===
  status: DONE
  hypothesis: Seed robustness of nomarker ablation: format marker contribution (~2pp) is consistent across random seeds, not an artifact of specific LoRA initializa
  metrics: {"accuracy": 0.9832, "n": 1190, "ci_95": [0.9756, 0.9899], "pass_f1": 0.9882, "fail_f1": 0.9705, "pass_precision": 0.9882, "pass_recall": 0.9882, "fail_precision": 0.9705, "fail_recall": 0.9705, "lift_over_majority": 0.2681}
  conclusion: success

=== exception_only_nomarker_seed456 ===
  status: DONE
  hypothesis: Seed robustness of nomarker ablation: format marker contribution (~2pp) is consistent across random seeds, not an artifact of specific LoRA initializa
  metrics: {"accuracy": 0.9807, "n": 1190, "errors": 23, "ci_95": [0.9712, 0.9871], "pass_f1": 0.9865, "fail_f1": 0.9658, "pass_precision": 0.9836, "pass_recall": 0.9894, "fail_precision": 0.9731, "fail_recall": 0.9587, "lift_over_majority": 0.266}
  conclusion: success

=== codellama13b_nomarker_seed42 ===
  status: DONE
  hypothesis: Cross-architecture marker contribution: format markers ([No exception data in trace], [ERROR] prefix) contribute ~2pp on CodeLlama-13B as on Qwen fami
  metrics: {}
  conclusion: killed

=== qwen15b_nomarker_seed42 ===
  status: DONE
  hypothesis: Cross-scale nomarker validation: format marker contribution (~2pp at 7B) is consistent at 1.5B, confirming markers provide a small but architecture-an
  metrics: {"accuracy": 0.978, "n": 1190, "accuracy_ci": [0.97, 0.986], "majority_baseline": 0.715, "lift": 0.263, "pass_precision": 0.97, "pass_recall": 1, "pass_f1": 0.98, "fail_precision": 1, "fail_recall": 0.92, "fail_f1": 0.96}
  conclusion: success

=== full_trace_256tok_seed42 ===
  status: DONE
  hypothesis: Token budget ablation (256 tokens): severely truncated full trace loses most diagnostic events, yielding accuracy near no-trace baseline because criti
  metrics: {"accuracy": 0.7882, "majority_baseline": 0.7151, "lift": 0.0731, "n": 1190, "pass_precision": 0.903, "pass_recall": 0.788, "pass_f1": 0.842, "fail_precision": 0.597, "fail_recall": 0.788, "fail_f1": 0.679, "accuracy_ci": [0.764, 0.81], "train_loss": 0.1094, "train_runtime_sec": 3047, "epochs": 3}
  conclusion: negative

=== full_trace_512tok_seed42 ===
  status: DONE
  hypothesis: Token budget ablation (512 tokens): moderate truncation retains some diagnostic events but still loses critical tail information, yielding accuracy be
  metrics: {"accuracy": 0.8042, "majority_baseline": 0.7151, "lift": 0.0891, "pass_precision": 0.8705, "pass_recall": 0.8531, "pass_f1": 0.8617, "fail_precision": 0.6489, "fail_recall": 0.6814, "fail_f1": 0.6647, "n": 1190, "accuracy_ci": [0.7815, 0.8261]}
  conclusion: negative

=== full_trace_1024tok_seed42 ===
  status: DONE
  hypothesis: Token budget ablation (1024 tokens): near-full trace budget should approach no-limit accuracy (~81.76%), testing whether the last few hundred tokens c
  metrics: {"accuracy": 0.7723, "majority_baseline": 0.7151, "lift": 0.0571, "n": 1190, "accuracy_ci": [0.7487, 0.7958], "pass_precision": 0.9006, "pass_recall": 0.7662, "pass_f1": 0.8279, "fail_precision": 0.573, "fail_recall": 0.7876, "fail_f1": 0.6634, "train_loss": 0.0634, "train_runtime_sec": 5553, "epochs": 3}
  conclusion: negative

=== full_trace_2048tok_seed42 ===
  status: DONE
  hypothesis: 
  metrics: {}
  conclusion: killed

=== full_trace_tail256_seed42 ===
  status: DONE
  hypothesis: Tail-256 truncation (keeping last 256 tokens of execution trace) still provides sufficient signal for verdict prediction, extending the budget curve b
  metrics: {"accuracy": 0.789, "accuracy_ci_lower": 0.765, "accuracy_ci_upper": 0.813, "pass_f1": 0.845, "fail_f1": 0.671, "n_test": 1190}
  conclusion: negative

=== full_trace_tail_256_seed42 ===
  status: DONE
  hypothesis: Tail-256 token budget: tests if diagnostic signal is concentrated in the last 256 tokens. If tail-256 approaches tail-512 (93.6%), signal is extremely
  metrics: {"accuracy": 0.7748, "accuracy_ci": [0.7496, 0.7975], "majority_baseline": 0.7151, "lift": 0.0597, "n": 1190, "pass_f1": 0.8333, "fail_f1": 0.6528}
  conclusion: negative

=== full_trace_tail_512_seed42 ===
  status: DONE
  hypothesis: Tail-truncation token budget: if tail-2048 >> head-2048, tail-512 reveals how concentrated the signal is. tail-512 ≈ tail-2048 means signal is in last
  metrics: {"accuracy": 0.936, "accuracy_ci": [0.922, 0.95], "majority_baseline": 0.7151, "lift": 0.221, "n": 1190, "pass_precision": 0.98, "pass_recall": 0.93, "pass_f1": 0.95, "fail_precision": 0.85, "fail_recall": 0.94, "fail_f1": 0.89}
  conclusion: success

=== full_trace_tail_1024_seed42 ===
  status: DONE
  hypothesis: Tail-1024 token budget: tests diminishing returns of tail context. If tail-1024 approaches tail-2048 (97.3%), 1024 tokens already captures nearly all 
  metrics: {"accuracy": 0.9647, "accuracy_ci": [0.9546, 0.9748], "majority_baseline": 0.7151, "lift": 0.2496, "n": 1190, "pass_f1": 0.9753, "fail_f1": 0.9381}
  conclusion: success

=== full_trace_tail_seed42 ===
  status: DONE
  hypothesis: Tail-truncation baseline: keeping the last 2048 tokens of full trace (where exception events concentrate) should significantly outperform head-truncat
  metrics: {"accuracy": 0.973, "accuracy_ci": [0.964, 0.982], "majority_baseline": 0.7151, "lift": 0.258, "n": 1190, "pass_precision": 0.98, "pass_recall": 0.99, "pass_f1": 0.98, "fail_precision": 0.97, "fail_recall": 0.94, "fail_f1": 0.95}
  conclusion: success

=== full_trace_tail256_seed42 ===
  status: DONE
  hypothesis: Tail-256 truncation (keeping last 256 tokens of execution trace) still provides sufficient signal for verdict prediction, extending the budget curve b
  metrics: {"accuracy": 0.789, "accuracy_ci_lower": 0.765, "accuracy_ci_upper": 0.813, "pass_f1": 0.845, "fail_f1": 0.671, "n_test": 1190}
  conclusion: negative

=== deepseek_full_trace_tail256_seed42 ===
  status: DONE
  hypothesis: DeepSeek tail-256 应在 75-82% 范围（与 Qwen-7B tail-256=78.9% 类似），确认 256-512 phase transition 是 architecture-independent
  metrics: {"accuracy": 0.7639, "accuracy_ci_lower": 0.7403, "accuracy_ci_upper": 0.7874, "pass_precision": 0.8058, "pass_recall": 0.8825, "pass_f1": 0.8424, "fail_precision": 0.6124, "fail_recall": 0.4661, "fail_f1": 0.5293, "majority_baseline": 0.7151, "lift": 0.0487, "eval_loss": 0.5117, "train_loss": 0.2367}
  conclusion: success

=== deepseek_full_trace_tail384_seed42 ===
  status: DONE
  hypothesis: DeepSeek-6.7B tail-384 应在 85-93% 之间（256→512 phase transition 的中间点），精确定位 phase transition 曲线形状
  metrics: {"accuracy": 0.807, "accuracy_ci_lower": 0.786, "accuracy_ci_upper": 0.829, "majority_baseline": 0.715, "lift": 0.092, "n": 1190, "pass_precision": 0.83, "pass_recall": 0.92, "pass_f1": 0.87, "fail_precision": 0.73, "fail_recall": 0.51, "fail_f1": 0.6}
  conclusion: success

=== deepseek_full_trace_tail1024_seed42 ===
  status: DONE
  hypothesis: DeepSeek tail-1024 可能低于 tail-512（如同 Qwen-7B non-monotonicity），因为 1024 tokens 包含了 noisy intermediate states；如果也出现 non-monotonicity 则确认跨架构
  metrics: {"accuracy": 0.9647, "accuracy_ci_lower": 0.9538, "accuracy_ci_upper": 0.9748, "pass_precision": 0.964, "pass_recall": 0.987, "pass_f1": 0.976, "fail_precision": 0.966, "fail_recall": 0.909, "fail_f1": 0.936, "majority_baseline": 0.7151, "n_test": 1190}
  conclusion: success

=== deepseek_full_trace_tail2048_seed42 ===
  status: DONE
  hypothesis: Tail-truncation signal concentration hypothesis generalizes across architectures: DeepSeek-Coder-6.7B with tail-2048 truncation should achieve accurac
  metrics: {"accuracy": 0.9496, "accuracy_ci_lower": 0.937, "accuracy_ci_upper": 0.9622, "pass_precision": 0.9692, "pass_recall": 0.96, "pass_f1": 0.9646, "fail_precision": 0.902, "fail_recall": 0.9233, "fail_f1": 0.9125, "n_test": 1190}
  conclusion: success

=== deepseek_full_trace_head2048_seed42 ===
  status: DONE
  hypothesis: Cross-architecture head-truncation: DeepSeek head-2048 should achieve 80-85% (similar to Qwen-7B 81.76%), and tail-2048 (94.96%) vs head-2048 gap shou
  metrics: {"accuracy": 0.787, "accuracy_ci_lower": 0.765, "accuracy_ci_upper": 0.81, "majority_baseline": 0.715, "lift_pp": 7.2, "pass_precision": 0.84, "pass_recall": 0.86, "pass_f1": 0.85, "fail_precision": 0.63, "fail_recall": 0.6, "fail_f1": 0.62}
  conclusion: success

=== codellama13b_full_trace_tail256_seed42 ===
  status: DONE
  hypothesis: CodeLlama-13B tail-256 应在 78-85%，与 7B 级模型 tail-256 (76-79%) 类似或略高，确认 256 tokens 信号不足是 universal 的
  metrics: {"accuracy": 0.779, "accuracy_ci_lower": 0.757, "accuracy_ci_upper": 0.803, "pass_f1": 0.843, "fail_f1": 0.626, "pass_precision": 0.856, "pass_recall": 0.831, "fail_precision": 0.604, "fail_recall": 0.649, "majority_baseline": 0.715, "lift": 0.064, "train_loss": 0.245, "eval_loss": 0.615}
  conclusion: success

=== codellama13b_full_trace_tail384_seed42 ===
  status: DONE
  hypothesis: CodeLlama-13B tail-384 (label_only_loss) 应在 85-95% 之间（256→512 phase transition 中间点），验证 label_only_loss 在短序列下也有效
  metrics: {"accuracy": 0.8269, "accuracy_ci_lower": 0.8067, "accuracy_ci_upper": 0.8471, "majority_baseline": 0.7151, "lift": 0.1118, "n": 1190, "pass_precision": 0.8314, "pass_recall": 0.9506, "pass_f1": 0.8871, "fail_precision": 0.8065, "fail_recall": 0.5162, "fail_f1": 0.6295}
  conclusion: negative

=== codellama13b_full_trace_tail2048_seed42 ===
  status: DONE
  hypothesis: CodeLlama-13B tail-2048 应在 95-98%，head-tail gap ≥15pp，确认 signal positional concentration 跨 4 模型
  metrics: {}
  conclusion: failed

=== codellama13b_full_trace_tail2048_seed42_v2 ===
  status: DONE
  hypothesis: CodeLlama-13B tail-2048 应在 95-98%，head-tail gap ≥15pp，确认 signal positional concentration 跨 4 模型
  metrics: {"accuracy_epoch1": 0.2849, "accuracy_epoch3": 0.2958, "pass_recall_epoch3": 0.016, "fail_recall_epoch3": 0.997, "majority_baseline": 0.715, "n_test": 1190, "note": "Catastrophic failure: model predicts fail for almost everything. Full-sequence loss dilution with CodeLlama tokenizer at 2048 tokens."}
  conclusion: negative

=== codellama13b_full_trace_tail2048_seed42_v3 ===
  status: DONE
  hypothesis: CodeLlama-13B tail-2048 用 label_only_loss 应恢复到 95-98%（与其他 3 模型 tail-2048 对齐），确认 v2 的 29.6% 源于 full-sequence loss 稀释
  metrics: {"accuracy_epoch1": 0.071, "accuracy_epoch3": 0.418, "pass_f1_epoch3": 0.416, "fail_f1_epoch3": 0.421, "pass_f1_epoch1": 0.035, "fail_f1_epoch1": 0.342, "train_loss": 0.785}
  conclusion: negative

=== codellama13b_full_trace_tail1024_seed42 ===
  status: DONE
  hypothesis: CodeLlama-13B tail-1024 应收敛到 96.5% 附近（与 DeepSeek 96.47%、Qwen-1.5B 96.6% 不可区分），确认 tail-1024 convergence band 跨 4 模型 universal
  metrics: {}
  conclusion: failed

=== codellama13b_full_trace_tail1024_seed42_v2 ===
  status: DONE
  hypothesis: CodeLlama-13B tail-1024 应收敛到 96.5% 附近（与 DeepSeek 96.47%、Qwen-1.5B 96.6% 不可区分），确认 tail-1024 convergence band 跨 4 模型 universal
  metrics: {"accuracy": 0.876, "accuracy_ci_lower": 0.856, "accuracy_ci_upper": 0.893, "majority_baseline": 0.715, "lift_pp": 16.1, "pass_precision": 0.85, "pass_recall": 1, "pass_f1": 0.92, "fail_precision": 1, "fail_recall": 0.56, "fail_f1": 0.72, "n_test": 1190, "train_loss": 0.0937, "eval_loss": 0.1859}
  conclusion: negative

=== codellama13b_full_trace_tail1024_seed42_v3 ===
  status: DONE
  hypothesis: CodeLlama-13B tail-1024 用 label_only_loss 应恢复到 ~96.5%（与 DeepSeek 96.47%、Qwen-1.5B 96.6% 对齐），确认 v2 的 87.6% 源于 full-sequence loss 稀释而非 tail-1024 条件本身
  metrics: {"accuracy_epoch1": 0.9824, "accuracy_epoch3": 0.9756, "pass_f1_epoch1": 0.988, "fail_f1_epoch1": 0.968, "pass_f1_epoch3": 0.983, "fail_f1_epoch3": 0.955, "best_accuracy": 0.9824, "best_epoch": 1, "overfitting": true}
  conclusion: success

=== codellama13b_full_trace_head2048_seed42 ===
  status: DONE
  hypothesis: CodeLlama-13B head-2048 truncation should yield 75-82% accuracy, confirming signal positional concentration pattern across 4 model families where tail
  metrics: {"accuracy": 0.7992, "majority_baseline": 0.7151, "lift": 0.084, "n_test": 1190, "pass_precision": 0.8566, "pass_recall": 0.8637, "pass_f1": 0.8602, "fail_precision": 0.6506, "fail_recall": 0.6372, "fail_f1": 0.6438, "train_loss": 0.0452, "eval_loss": 0.111, "accuracy_ci_lower": 0.7765, "accuracy_ci_upper": 0.8227}
  conclusion: success

=== qwen15b_full_trace_tail256_seed42 ===
  status: DONE
  hypothesis: Cross-scale tail-256: Qwen-1.5B tail-256 should show similar accuracy to 7B tail-256 (78.9%), confirming the 256-512 phase transition is signal-limite
  metrics: {"accuracy": 0.726, "accuracy_ci_lower": 0.7, "accuracy_ci_upper": 0.753, "majority_baseline": 0.715, "lift_over_majority": 0.011, "lift_ci_lower": -0.021, "lift_ci_upper": 0.044, "pass_precision": 0.82, "pass_recall": 0.79, "pass_f1": 0.8, "fail_precision": 0.52, "fail_recall": 0.57, "fail_f1": 0.54, "eval_loss": 0.5936, "train_loss": 0.2687}
  conclusion: negative

=== qwen15b_full_trace_tail384_seed42 ===
  status: DONE
  hypothesis: Qwen-1.5B tail-384 应在 80-90% 之间（小模型在 transition zone 可能更低），精确定位 phase transition 曲线形状
  metrics: {"accuracy": 0.7361, "majority_baseline": 0.7151, "lift": 0.021, "n": 1190, "pass_precision": 0.8069, "pass_recall": 0.8296, "pass_f1": 0.8181, "fail_precision": 0.5397, "fail_recall": 0.5015, "fail_f1": 0.5199, "accuracy_ci": [0.7101, 0.7622]}
  conclusion: negative

=== qwen15b_full_trace_tail1024_seed42 ===
  status: DONE
  hypothesis: 1.5B tail-1024 可能低于 tail-512 (95.6%)，如同 7B non-monotonicity；因中等长度 trace 包含 noisy intermediate states
  metrics: {"accuracy": 0.966, "accuracy_ci_low": 0.955, "accuracy_ci_high": 0.976, "pass_precision": 0.96, "pass_recall": 0.99, "pass_f1": 0.98, "fail_precision": 0.97, "fail_recall": 0.91, "fail_f1": 0.94, "eval_loss": 0.1983, "train_loss": 0.1187, "majority_baseline": 0.715, "lift_over_majority_pp": 25}
  conclusion: success

=== qwen15b_full_trace_tail2048_seed42 ===
  status: DONE
  hypothesis: Tail-truncation concentrates diagnostic signal (final execution states, exceptions) at training time. If this hypothesis holds, Qwen2.5-Coder-1.5B wit
  metrics: {"accuracy": 0.979, "accuracy_ci_lower": 0.9706, "accuracy_ci_upper": 0.9874, "pass_precision": 0.9758, "pass_recall": 0.9953, "pass_f1": 0.9855, "fail_precision": 0.9876, "fail_recall": 0.9381, "fail_f1": 0.9622, "n_test": 1190}
  conclusion: success

=== qwen15b_full_trace_head2048_seed42 ===
  status: DONE
  hypothesis: Cross-scale head-truncation: Qwen-1.5B head-2048 should achieve 75-82%, and tail-2048 (97.90%) vs head-2048 gap should be >=15pp, confirming signal po
  metrics: {"accuracy": 0.7529, "accuracy_ci_lower": 0.7286, "accuracy_ci_upper": 0.7782, "pass_precision": 0.799, "pass_recall": 0.874, "pass_f1": 0.835, "fail_precision": 0.587, "fail_recall": 0.448, "fail_f1": 0.508, "n_test": 1190}
  conclusion: success

=== debugbench_exception_only_seed42 ===
  status: DONE
  hypothesis: Out-of-distribution generalization: exception_only signal sufficiency transfers to DebugBench (different bug categories, different code styles) becaus
  metrics: {"accuracy": 1, "majority_baseline": 0.5141, "lift": 0.4859, "n": 426, "pass_precision": 1, "pass_recall": 1, "pass_f1": 1, "fail_precision": 1, "fail_recall": 1, "fail_f1": 1, "accuracy_ci_wilson": [0.9914, 1], "accuracy_ci_bootstrap": [1, 1], "train_loss": 0.2435, "eval_loss": 0.4157, "train_runtime_sec": 837}
  conclusion: success

=== debugbench_no_trace_seed42 ===
  status: DONE
  hypothesis: DebugBench no-trace baseline: without execution trace, model relies on code structure alone — on DebugBench (50/50 pass/fail) this yields higher lift 
  metrics: {"accuracy": 0.9671, "majority_baseline": 0.5141, "lift": 0.4531, "pass_precision": 1, "pass_recall": 0.936, "pass_f1": 0.967, "fail_precision": 0.937, "fail_recall": 1, "fail_f1": 0.967, "accuracy_ci": [0.948, 0.984], "train_loss": 0.249, "eval_loss": 0.532}
  conclusion: success

=== debugbench_vota_seed42 ===
  status: DONE
  hypothesis: DebugBench VOTA generalization: VOTA compressed trace maintains near-perfect accuracy on out-of-distribution bugs, confirming trace compression captur
  metrics: {"accuracy": 0.9977, "majority_baseline": 0.5141, "lift": 0.4836, "n": 426, "pass_precision": 1, "pass_recall": 1, "pass_f1": 1, "fail_precision": 1, "fail_recall": 1, "fail_f1": 1, "accuracy_ci": [0.993, 1], "train_loss": 0.098, "eval_loss": 0.1179, "eval_mean_token_accuracy": 0.9737, "errors": 1}
  conclusion: success

=== debugbench_exception_bug_fix ===
  status: DONE
  hypothesis: BUG FIX: compress_exception_only() only checked trace_raw events, missing 625/1006 empty-trace fails (syntax errors) + 5 event-capped samples. Fix: fa
  metrics: {}
  conclusion: success

=== fewshot_gpt4o_exception_only_0shot ===
  status: DONE
  hypothesis: Frontier LLM (GPT-4o) with zero-shot prompting can match SFT Qwen-7B on exception_only test verdict prediction because the task may be solvable via ge
  metrics: {"accuracy": 0.8798, "fail_f1": 0.8228}
  conclusion: negative

=== fewshot_gpt4o_exception_only_3shot ===
  status: DONE
  hypothesis: Adding 3-shot examples to GPT-4o improves exception_only verdict prediction over zero-shot by providing task format demonstrations and calibrating out
  metrics: {"accuracy": 0.8681, "fail_f1": 0.7995}
  conclusion: negative

=== fewshot_gpt4o_no_trace_0shot ===
  status: DONE
  hypothesis: GPT-4o zero-shot on no_trace condition can outperform SFT Qwen-7B because frontier LLMs have stronger code understanding that compensates for missing 
  metrics: {"accuracy": 0.8445, "fail_f1": 0.7543}
  conclusion: success

=== fewshot_gpt41_exception_only_0shot ===
  status: DONE
  hypothesis: GPT-4.1 zero-shot on exception_only condition performs comparably to GPT-4o because both are frontier models with similar code reasoning capabilities.
  metrics: {"accuracy": 0.8218, "fail_f1": 0.7452}
  conclusion: negative

=== fewshot_gpt41_exception_only_3shot ===
  status: DONE
  hypothesis: Adding 3-shot examples to GPT-4.1 improves exception_only verdict prediction over zero-shot by providing task format demonstrations.
  metrics: {"accuracy": 0.8193, "fail_f1": 0.7413}
  conclusion: negative

=== fewshot_gpt41_no_trace_0shot ===
  status: DONE
  hypothesis: GPT-4.1 zero-shot on no_trace condition can outperform SFT Qwen-7B because frontier LLMs have stronger code understanding that compensates for missing
  metrics: {"accuracy": 0.7731, "fail_f1": 0.6608}
  conclusion: success

=== fewshot_qwen7b_exception_only ===
  status: DONE
  hypothesis: Few-shot (3 examples) improves over zero-shot (89.08%) but remains far below SFT (99.83%) because 3 in-context examples cannot cover all caught except
  metrics: {"accuracy": 0.9084, "accuracy_ci_lower": 0.8908, "accuracy_ci_upper": 0.9244, "pass_precision": 0.9245, "pass_recall": 0.9495, "pass_f1": 0.9368, "fail_precision": 0.8639, "fail_recall": 0.8053, "fail_f1": 0.8336, "n_test": 1190, "n_unknown": 0}
  conclusion: success

=== attention_gradient_analysis ===
  status: DONE
  hypothesis: In the full_trace model, execution trace tokens dominate input length (~70%+ of tokens) but receive disproportionately low attention and gradient sign
  metrics: {}
  conclusion: success

=== zeroshot_codellama13b_exception_only ===
  status: DONE
  hypothesis: Zero-shot cross-scale baseline: untuned CodeLlama-13B-Instruct (largest model tested) still cannot match SFT accuracy on exception_only verdict predic
  metrics: {"accuracy": 0.5101, "accuracy_ci_lower": 0.4824, "accuracy_ci_upper": 0.5395, "pass_precision": 1, "pass_recall": 0.3502, "pass_f1": 0.5187, "fail_precision": 0.3585, "fail_recall": 0.9115, "fail_f1": 0.5146, "n_test": 1190, "n_unknown": 30}
  conclusion: success

=== zeroshot_deepseek7b_exception_only ===
  status: DONE
  hypothesis: Zero-shot cross-model baseline: untuned DeepSeek-Coder-6.7B-Instruct similarly cannot reach SFT-level accuracy on exception_only verdict prediction, c
  metrics: {"accuracy": 0.9059, "accuracy_ci_lower": 0.8899, "accuracy_ci_upper": 0.9218, "pass_precision": 0.9743, "pass_recall": 0.8919, "pass_f1": 0.9313, "fail_precision": 0.7762, "fail_recall": 0.941, "fail_f1": 0.8507, "n_test": 1190, "n_unknown": 0}
  conclusion: success

=== zeroshot_qwen15b_exception_only ===
  status: DONE
  hypothesis: Zero-shot cross-scale baseline: Qwen-1.5B zero-shot may perform poorly (similar to CodeLlama-13B) due to limited capacity, but SFT normalizes it to 99
  metrics: {"accuracy": 0.9345, "accuracy_ci_lower": 0.9202, "accuracy_ci_upper": 0.9479, "pass_f1": 0.969, "fail_f1": 0.873, "pass_recall": 0.9906, "fail_recall": 0.7935, "n_test": 1190, "n_unknown": 24}
  conclusion: success

=== zeroshot_qwen7b_exception_only ===
  status: DONE
  hypothesis: Zero-shot prompting baseline: untuned Qwen2.5-7B-Instruct cannot match SFT accuracy (99.83%) on exception_only verdict prediction because distinguishi
  metrics: {"accuracy": 0.8908, "accuracy_ci_lower": 0.8731, "accuracy_ci_upper": 0.9076, "pass_precision": 0.8815, "pass_recall": 0.9788, "pass_f1": 0.9276, "fail_precision": 0.9265, "fail_recall": 0.6696, "fail_f1": 0.7774, "n_test": 1190, "n_unknown": 0}
  conclusion: success

=== qwen1.5b_exception_only_seed42 ===
  status: DONE
  hypothesis: Qwen-1.5B exception_only 应达 ≥99% accuracy，确认 minimal sufficient signal 在 1.5B scale 有效，signal quality 主导 model capacity
  metrics: {}
  conclusion: killed

=== qwen1.5b_full_trace_seed42 ===
  status: DONE
  hypothesis: Qwen-1.5B full_trace 应达 ≥96% accuracy，确认 1.5B 小模型在 full trace 条件下与 7B 可比（trace quality 主导而非 model capacity）
  metrics: {}
  conclusion: killed

=== qwen1.5b_no_trace_seed42 ===
  status: DONE
  hypothesis: Qwen-1.5B no_trace 应在 65-75% (≈majority baseline)，确认无 trace 小模型表现更差、scale 无法补偿
  metrics: {"accuracy": 0.7261, "accuracy_ci_lower": 0.7008, "accuracy_ci_upper": 0.7529, "majority_baseline": 0.7151, "lift_pp": 1.09, "pass_precision": 0.831, "pass_recall": 0.774, "pass_f1": 0.802, "fail_precision": 0.516, "fail_recall": 0.605, "fail_f1": 0.557}
  conclusion: success

=== qwen1.5b_vota_seed42 ===
  status: DONE
  hypothesis: Qwen-1.5B VOTA 应在 82-90% accuracy，可能略低于 7B 因 VOTA 条件下 scale-sensitivity 更明显
  metrics: {}
  conclusion: killed

=== codellama_exception_only_seed42 ===
  status: DONE
  hypothesis: CodeLlama-13B exception_only 应达 ≥99.33% accuracy，与其他 3 模型一致，确认 minimal sufficient signal 跨 4 模型 3 架构 1.5B-13B universal
  metrics: {}
  conclusion: killed

=== codellama_no_trace_seed42 ===
  status: DONE
  hypothesis: CodeLlama-13B no_trace 应在 70-78% (≈majority baseline)，确认无 trace 时 13B scale 无法补偿信息缺失
  metrics: {}
  conclusion: killed

=== codellama_vota_seed42 ===
  status: DONE
  hypothesis: CodeLlama-13B VOTA 应在 85-92% accuracy，与 Qwen-7B/DeepSeek VOTA 对齐，作 rebuttal 储备验证 ablation condition 跨 scale 一致性
  metrics: {}
  conclusion: killed

=== eval_missing_predictions_batch ===
  status: DONE
  hypothesis: Utility: batch re-evaluation of checkpoints missing predictions.jsonl to complete provenance records and enable systematic cross-experiment comparison
  metrics: {}
  conclusion: success

=== eval_missing_predictions_batch_v2 ===
  status: DONE
  hypothesis: Utility: second batch re-evaluation pass for remaining checkpoints without predictions.jsonl, ensuring all DONE experiments have comparable evaluation
  metrics: {}
  conclusion: success
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "1ac71a31-29a9-4a83-a08b-959e3d9f5762"
}
```

</details>

---


### System

_source line 67_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Check Qwen-7B canonical experiment metrics",
  "usage": {
    "total_tokens": 59024,
    "tool_uses": 12,
    "duration_ms": 122167
  },
  "last_tool_name": "Bash",
  "uuid": "ffdec197-eb4b-4fde-8ac8-105ba4688b48",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 68_

<details open><summary>🔧 Tool call — Bash · `toolu_01XGxmUT6uV5YoqyoYQU8HNi`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\ninner = json.loads(outer['result'])\nexperiments = inner['data']['experiments']\n\n# Check remaining experiments I haven't fully covered\nremaining = [\n    'deepseek_full_trace_tail256_seed42', 'deepseek_full_trace_tail384_seed42',\n    'codellama13b_full_trace_tail256_seed42', 'codellama13b_full_trace_tail384_seed42',\n    'codellama13b_full_trace_tail512_seed42',\n    'vota_exception_only_seed42_v2',  # already got\n    # check for seed42 canonical Qwen-7B experiments I may have missed\n    'full_trace_seed42', 'no_trace_seed42_v4', 'no_trace_seed42_v5',\n    # exception_only seed42 canonical\n]\n\n# also let's check all Qwen-7B VOTA seed42 canonical\ncanonical_qwen7b = {\n    'exception_only': 'exception_only_seed123',  # seed42 has same accuracy, use seed123 \n    'full_trace': 'full_trace_seed123',  # canonical 3-seed\n    'no_trace': 'no_trace_seed42_v5',  # canonical\n    'vota': 'vota_seed42_v4',  # canonical\n    'ae_only': 'ae_only_seed456',  # has comparison\n    'loop_only': 'loop_only_seed456',  # has comparison\n    'label_only': 'full_trace_label_only_seed42',\n}\n\n# Also look at the exception_only seed42 canonical\neid = 'exception_only_seed123'\nexp = experiments.get(eid, {})\nprint(f\"=== exception_only_seed123 (canonical Qwen-7B) ===\")\nprint(json.dumps(exp.get('metrics', {}), indent=2))\n\n# And check if there's a canonical seed42 for exception_only Qwen-7B\nprint(\"\\n\\nSearching for Qwen-7B exception_only seed42 canonical...\")\nfor eid in ['exception_only_seed42', 'vota_exception_only_seed42_v2']:\n    if eid in experiments:\n        exp = experiments[eid]\n        print(f\"\\n=== {eid} ===\")\n        print(json.dumps(exp.get('metrics', {}), indent=2))\n        print(f\"  conclusion: {exp.get('conclusion')}\")\nPYEOF\n",
  "description": "Check Qwen-7B canonical experiment metrics"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "4a6a97ba-d6d2-4913-82b0-47d4f179b7b1",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_01C7FKYWi72rt3Lw56qTvhyJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10828,
      "cache_read_input_tokens": 47625,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 10828,
        "ephemeral_1h_input_tokens": 0
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

_source line 69 · 2026-05-23T19:19:47.741Z_

<details><summary>↩ Tool result · `toolu_01XGxmUT6uV5YoqyoYQU8HNi`</summary>

```text
=== exception_only_seed123 (canonical Qwen-7B) ===
{
  "accuracy": 0.9983,
  "accuracy_ci": [
    0.9958,
    1
  ],
  "majority_baseline": 0.7151,
  "lift": 0.2832,
  "n": 1190,
  "pass_precision": 1,
  "pass_recall": 0.9976,
  "pass_f1": 0.9988,
  "fail_precision": 0.9941,
  "fail_recall": 1,
  "fail_f1": 0.9971,
  "train_loss": 0.1096,
  "train_runtime_sec": 7507,
  "epochs": 3,
  "seed_comparison": {
    "seed42_accuracy": 0.9983,
    "seed456_accuracy": 0.9983,
    "seed123_accuracy": 0.9983,
    "max_diff": 0,
    "note": "identical accuracy to 4 decimal places across all 3 seeds (42/456/123); each has exactly 2/1190 errors; exception_only fully seed-robust"
  }
}


Searching for Qwen-7B exception_only seed42 canonical...

=== vota_exception_only_seed42_v2 ===
{
  "accuracy": 0.9983,
  "majority_baseline": 0.7151,
  "lift": 0.2832,
  "n": 1190,
  "pass_precision": 1,
  "pass_recall": 0.998,
  "pass_f1": 0.999,
  "fail_precision": 0.994,
  "fail_recall": 1,
  "fail_f1": 0.997,
  "lift_vs_notrace": 0.2471,
  "lift_vs_notrace_ci_lower": 0.2227,
  "lift_vs_notrace_ci_upper": 0.2714,
  "lift_vs_fulltrace": 0.1807,
  "lift_vs_fulltrace_ci_lower": 0.1588,
  "lift_vs_fulltrace_ci_upper": 0.2034,
  "lift_vs_vota": 0.0067,
  "lift_vs_vota_ci_lower": 0.0017,
  "lift_vs_vota_ci_upper": 0.0126,
  "lift_vs_vota_pvalue": 0.01
}
  conclusion: success
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "05bb487d-7ad6-448b-8b5b-114f3335e305"
}
```

</details>

---


### System

_source line 70_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Compile comprehensive audit extract and write to artifacts file",
  "usage": {
    "total_tokens": 60521,
    "tool_uses": 13,
    "duration_ms": 332730
  },
  "last_tool_name": "Bash",
  "uuid": "22386076-d58b-42fa-ad3f-836930901683",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 71_

<details open><summary>🔧 Tool call — Bash · `toolu_01C9E9JJnSAWMfQ51mMNp4jB`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nfilepath = \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\"\n\nwith open(filepath, 'r') as f:\n    outer = json.load(f)\n\ninner = json.loads(outer['result'])\nexperiments = inner['data']['experiments']\n\noutput_path = \"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts/_audit_registry_extract.txt\"\n\nlines = []\nlines.append(\"=\" * 100)\nlines.append(\"REGISTRY AUDIT EXTRACT — trace-verdict-study\")\nlines.append(\"Generated from: mcp-agent-ml-research-read_registry-1779563834793.txt\")\nlines.append(f\"Total experiments in registry: {len(experiments)}\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\n# ============================================================================================\n# SECTION 1: TABLE 1 — MAIN CONDITION RESULTS (Qwen-7B canonical, all seeds)\n# ============================================================================================\nlines.append(\"=\" * 100)\nlines.append(\"SECTION 1: TABLE 1 CANDIDATES — Main SFT Conditions (Qwen2.5-Coder-7B-Instruct, n=1190)\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\n# --- exception_only (Qwen-7B) ---\nlines.append(\"--- exception_only (Qwen-7B) ---\")\nlines.append(\"  Seed 42 accuracy: 0.9983 (from seed_comparison in exception_only_seed123)\")\nlines.append(\"  Seed 123 accuracy: 0.9983  | exp_id: exception_only_seed123\")\nlines.append(\"    accuracy_ci: [0.9958, 1.0]\")\nlines.append(\"    pass_precision: 1.0000  pass_recall: 0.9976  pass_f1: 0.9988\")\nlines.append(\"    fail_precision: 0.9941  fail_recall: 1.0000  fail_f1: 0.9971\")\nlines.append(\"    majority_baseline: 0.7151  lift: 0.2832  n: 1190\")\nlines.append(\"  Seed 456 accuracy: 0.9983  | exp_id: exception_only_seed456\")\nlines.append(\"    accuracy_ci: [0.9958, 1.0]  eval_loss: 0.4629  train_loss: 0.1087\")\nlines.append(\"  MEAN across 3 seeds: 0.9983 ± 0.0000 (all identical, max_diff=0)\")\nlines.append(\"  NOTE: each seed has exactly 2/1190 errors\")\nlines.append(\"\")\n\n# --- full_trace (Qwen-7B) ---\nlines.append(\"--- full_trace (Qwen-7B) ---\")\nlines.append(\"  Seed 123 accuracy: 0.7958  | exp_id: full_trace_seed123\")\nlines.append(\"    accuracy_ci_lower: 0.7714  accuracy_ci_upper: 0.8202\")\nlines.append(\"    pass_precision: 0.8753  pass_recall: 0.8331  pass_f1: 0.8537\")\nlines.append(\"    fail_precision: 0.6263  fail_recall: 0.7021  fail_f1: 0.6620\")\nlines.append(\"    majority_baseline: 0.7151  lift: 0.0807  n: 1190\")\nlines.append(\"  Seed 42 (v5) accuracy: 0.8176  | exp_id: full_trace_seed42_v5\")\nlines.append(\"    accuracy_ci_lower: 0.797  accuracy_ci_upper: 0.839\")\nlines.append(\"    pass_precision: 0.8774  pass_recall: 0.8660  pass_f1: 0.8717\")\nlines.append(\"    fail_precision: 0.6743  fail_recall: 0.6962  fail_f1: 0.6851\")\nlines.append(\"    lift: 0.1025  lift_vs_notrace: 0.0664  (CI: [0.0437, 0.0899])\")\nlines.append(\"    epoch_level: epoch1=0.8303 epoch2=0.7630 epoch3=0.8176 (non-monotonic)\")\nlines.append(\"  Seed 456 accuracy: 0.8050  | exp_id: full_trace_seed456\")\nlines.append(\"    accuracy_ci_lower: 0.7824  accuracy_ci_upper: 0.8269\")\nlines.append(\"    pass_f1: 0.8637  fail_f1: 0.6578\")\nlines.append(\"    lift: 0.0899\")\nlines.append(\"  Seed 123 (qwen7b_full_trace_seed123) accuracy: 0.8020  | exp_id: qwen7b_full_trace_seed123\")\nlines.append(\"    ci_lower: 0.778  ci_upper: 0.825  lift_pp: 8.7\")\nlines.append(\"  Seed 456 (v2) accuracy: 0.8235  | exp_id: qwen7b_full_trace_seed456_v2\")\nlines.append(\"    ci_lower: 0.8017  ci_upper: 0.8454  lift_pp: 10.84\")\nlines.append(\"  3-SEED MEAN (seed42=0.8176, seed123=0.8020, seed456=0.8235): ~0.814\")\nlines.append(\"\")\n\n# --- no_trace (Qwen-7B) ---\nlines.append(\"--- no_trace (Qwen-7B) ---\")\nlines.append(\"  Seed 42 (v4/v5) accuracy: 0.7513  | exp_id: no_trace_seed42_v5\")\nlines.append(\"    accuracy_ci_lower: 0.7277  accuracy_ci_upper: 0.7748\")\nlines.append(\"    pass_precision: 0.8776  pass_recall: 0.7579  pass_f1: 0.8134\")\nlines.append(\"    fail_precision: 0.5473  fail_recall: 0.7345  fail_f1: 0.6272\")\nlines.append(\"    majority_baseline: 0.7151  lift: 0.0361  (CI: [0.0042, 0.0706])\")\nlines.append(\"    epoch_level: epoch1=0.7429 epoch2=0.7630 epoch3=0.7513\")\nlines.append(\"  Seed 123 accuracy: 0.7908  | exp_id: no_trace_seed123\")\nlines.append(\"    pass_f1: 0.8523  fail_f1: 0.6581  n: 1190\")\nlines.append(\"  Seed 456 accuracy: 0.7504  | exp_id: no_trace_seed456\")\nlines.append(\"    accuracy_ci: [0.7235, 0.7748]  pass_f1: 0.8119  fail_f1: 0.6292\")\nlines.append(\"  3-SEED MEAN (seed42=0.7513, seed123=0.7908, seed456=0.7504): ~0.764\")\nlines.append(\"\")\n\n# --- VOTA (Qwen-7B) ---\nlines.append(\"--- VOTA (Qwen-7B) ---\")\nlines.append(\"  Seed 42 (v4) accuracy: 0.9563  | exp_id: vota_seed42_v4  [canonical v4]\")\nlines.append(\"    lift: 0.2412  lift_vs_notrace: 0.2050  (CI: [0.177, 0.234])\")\nlines.append(\"    pass_precision: 0.9440  pass_recall: 0.9980  pass_f1: 0.9700\")\nlines.append(\"    fail_precision: 0.9930  fail_recall: 0.8530  fail_f1: 0.9170\")\nlines.append(\"  Seed 42 (v5) accuracy: 0.9941  | exp_id: vota_seed42_v5  [note: diff script]\")\nlines.append(\"    pass_precision: 1.0000  pass_recall: 0.9918  pass_f1: 0.9959\")\nlines.append(\"    fail_precision: 0.9798  fail_recall: 1.0000  fail_f1: 0.9898  n: 1190\")\nlines.append(\"  Seed 123 accuracy: 0.9866  | exp_id: qwen7b_vota_seed123\")\nlines.append(\"    accuracy_ci_lower: 0.9790  accuracy_ci_upper: 0.9925  lift: 0.2714\")\nlines.append(\"    pass_f1: 0.9905  fail_f1: 0.9769\")\nlines.append(\"  Seed 456 accuracy: 0.9908  | exp_id: qwen7b_vota_seed456\")\nlines.append(\"    accuracy_ci_lower: 0.9849  accuracy_ci_upper: 0.9958  lift: 0.2756\")\nlines.append(\"    pass_f1: 0.9935  fail_f1: 0.9840\")\nlines.append(\"  Seed 456 v2 accuracy: 0.9908  | exp_id: vota_seed456_v2\")\nlines.append(\"    ci_95: [0.985, 0.996]  pass_f1: 0.9930  fail_f1: 0.9840\")\nlines.append(\"  3-SEED MEAN (seed42=0.9941, seed123=0.9866, seed456=0.9908): ~0.991\")\nlines.append(\"    [using v5 for seed42; note v4 gives 0.9563 — version discrepancy]\")\nlines.append(\"\")\n\n# --- ae_only (Qwen-7B) ---\nlines.append(\"--- ae_only (Qwen-7B) ---\")\nlines.append(\"  Seed 42 accuracy: 0.9992  | exp_id: vota_ae_only_seed42\")\nlines.append(\"    accuracy_ci: [0.9975, 1.0000]\")\nlines.append(\"    bootstrap vs no_trace: diff=0.2479 CI=[0.2235, 0.2731] p=0\")\nlines.append(\"    bootstrap vs exception_only: diff=0.0008 CI=[-0.0017, 0.0034] p=0.8002 (n.s.)\")\nlines.append(\"    bootstrap vs vota: diff=0.0050 CI=[0.0017, 0.0092] p=0.0046\")\nlines.append(\"  Seed 123 accuracy: 0.9908  | exp_id: ae_only_seed123\")\nlines.append(\"    pass_recall: 0.987  fail_recall: 1.0  n: 1190  lift: 0.2757\")\nlines.append(\"  Seed 456 accuracy: 0.9992  | exp_id: ae_only_seed456\")\nlines.append(\"    lift: 0.2841  n: 1190\")\nlines.append(\"    seed_comparison: seed42=0.9992 seed123=0.9908 seed456=0.9992 → mean=0.9964 ± 0.0049\")\nlines.append(\"  3-SEED MEAN: 0.9964 ± 0.0049\")\nlines.append(\"\")\n\n# --- loop_only (Qwen-7B) ---\nlines.append(\"--- loop_only (Qwen-7B) ---\")\nlines.append(\"  Seed 42 accuracy: 0.8563  | exp_id: vota_loop_only_seed42\")\nlines.append(\"    accuracy_ci: [0.8353, 0.8756]  lift: 0.1412\")\nlines.append(\"    pass_precision: 0.9239  pass_recall: 0.8707  pass_f1: 0.8966\")\nlines.append(\"    fail_precision: 0.7165  fail_recall: 0.8201  fail_f1: 0.7648\")\nlines.append(\"    bootstrap vs vota: diff=-0.1378 CI=[-0.1571, -0.1185] (sig)\")\nlines.append(\"  Seed 123 accuracy: 0.8588  | exp_id: loop_only_seed123\")\nlines.append(\"    accuracy_ci: [0.8403, 0.8773]  lift: 0.1437\")\nlines.append(\"    pass_f1: 0.8999  fail_f1: 0.7607\")\nlines.append(\"  Seed 456 accuracy: 0.8664  | exp_id: loop_only_seed456\")\nlines.append(\"    accuracy_ci: [0.8470, 0.8840]\")\nlines.append(\"    pass_f1: 0.9053  fail_f1: 0.7732\")\nlines.append(\"    seed_comparison: seed42=0.8563 seed123=0.8588 seed456=0.8664 → mean=0.8605 ± 0.0053\")\nlines.append(\"  3-SEED MEAN: 0.8605 ± 0.0053\")\nlines.append(\"\")\n\n# --- label_only / full_trace_label_only (Qwen-7B) ---\nlines.append(\"--- label_only / full_trace_label_only_loss (Qwen-7B) ---\")\nlines.append(\"  Seed 42 (full_trace, label_only_loss) accuracy: 0.8622  | exp_id: full_trace_label_only_seed42\")\nlines.append(\"    accuracy_ci_lower: 0.8437  accuracy_ci_upper: 0.8807  lift: 0.1471\")\nlines.append(\"    pass_f1: 0.9063  fail_f1: 0.7397  n: 1190\")\nlines.append(\"    lift_vs_notrace: 0.1109  CI: [0.0849, 0.1370]\")\nlines.append(\"    lift_vs_standard_fulltrace: 0.0445  CI: [0.0235, 0.0655]  p=0\")\nlines.append(\"  Seed 123 accuracy: 0.8689  | exp_id: qwen7b_full_trace_label_only_seed123\")\nlines.append(\"    accuracy_ci: [0.8496, 0.8874]  pass_f1: 0.9121  fail_f1: 0.7426  lift: 0.1538\")\nlines.append(\"  Seed 456 accuracy: 0.8470  | exp_id: qwen7b_full_trace_label_only_seed456\")\nlines.append(\"    accuracy_ci: [0.827, 0.866]  pass_f1: 0.9000  fail_f1: 0.7100  lift: 0.1319\")\nlines.append(\"  NOTE: standalone label_only seeds (no trace at all):\")\nlines.append(\"    label_only_seed123 accuracy: 0.8706  pass_f1: 0.915  fail_f1: 0.729\")\nlines.append(\"    label_only_seed456 accuracy: 0.8590  pass_f1: 0.905  fail_f1: 0.727\")\nlines.append(\"\")\n\nlines.append(\"\")\nlines.append(\"=\" * 100)\nlines.append(\"SECTION 2: CROSS-MODEL TABLE — All 4 Models × Main Conditions\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\n# --- DeepSeek-Coder-6.7B ---\nlines.append(\"--- DeepSeek-Coder-6.7B ---\")\nlines.append(\"\")\nlines.append(\"  exception_only:\")\nlines.append(\"    Seed 42  accuracy: 0.9933  | exp_id: deepseek_exception_only_seed42\")\nlines.append(\"      pass_f1: 0.9953  fail_f1: 0.9883  n: 1190  lift: 0.2782\")\nlines.append(\"    Seed 123 accuracy: 0.9950  | exp_id: deepseek_exception_only_seed123_v2\")\nlines.append(\"    Seed 456 accuracy: 0.9933  | exp_id: deepseek_exception_only_seed456\")\nlines.append(\"      accuracy_ci: [0.9882, 0.9975]\")\nlines.append(\"      seed_comparison: seed42=0.9933 seed456=0.9933 seed123=0.9109 (outlier)\")\nlines.append(\"      NOTE: seed123 v1 was OOM-crash; seed123_v2 = 0.9950 (canonical)\")\nlines.append(\"    3-SEED MEAN (using v2 for seed123): ~0.994\")\nlines.append(\"\")\nlines.append(\"  full_trace:\")\nlines.append(\"    Seed 42 (v3) accuracy: 0.7916  | exp_id: deepseek_full_trace_seed42_v3\")\nlines.append(\"      accuracy_ci: [0.768, 0.813]  lift: 0.0765\")\nlines.append(\"      pass_f1: 0.854  fail_f1: 0.637  n: 1190\")\nlines.append(\"    (v1, v2 = killed/negative)\")\nlines.append(\"\")\nlines.append(\"  no_trace:\")\nlines.append(\"    Seed 42 accuracy: 0.7336  | exp_id: deepseek_no_trace_seed42\")\nlines.append(\"      accuracy_ci: [0.708, 0.757]  lift: 0.0185\")\nlines.append(\"      pass_f1: 0.8130  fail_f1: 0.5390  n: 1190\")\nlines.append(\"\")\nlines.append(\"  VOTA:\")\nlines.append(\"    Seed 42 accuracy: 0.8445  | exp_id: deepseek_vota_seed42  [early canonical]\")\nlines.append(\"      accuracy_ci: [0.826, 0.864]  lift: 0.1294\")\nlines.append(\"      pass_f1: 0.9020  fail_f1: 0.6250\")\nlines.append(\"    Seed 123 accuracy: 0.9916  | exp_id: deepseek_vota_seed123\")\nlines.append(\"      accuracy_ci_lower: 0.9857  accuracy_ci_upper: 0.9966\")\nlines.append(\"    Seed 456 accuracy: 0.9933  | exp_id: deepseek_vota_seed456\")\nlines.append(\"    NOTE: large seed variance — seed42 may be from different pipeline version\")\nlines.append(\"\")\nlines.append(\"  ae_only:\")\nlines.append(\"    Seed 42 accuracy: 0.9874  | exp_id: deepseek_ae_only_seed42\")\nlines.append(\"      accuracy_ci: [0.9807, 0.9933]  pass_f1: 0.9910  fail_f1: 0.9770\")\nlines.append(\"    Seed 123 accuracy: 0.9832  | exp_id: deepseek_ae_only_seed123\")\nlines.append(\"\")\nlines.append(\"  loop_only:\")\nlines.append(\"    Seed 42 accuracy: 0.8126  | exp_id: deepseek_loop_only_seed42\")\nlines.append(\"      accuracy_ci: [0.7908, 0.8345]\")\nlines.append(\"    Seed 123 accuracy: 0.8126  | exp_id: deepseek_loop_only_seed123\")\nlines.append(\"      accuracy_ci: [0.792, 0.834]\")\nlines.append(\"    Seed 456 accuracy: 0.784   | exp_id: deepseek_loop_only_seed456\")\nlines.append(\"      fail_f1: 0.63  majority_baseline: 0.715\")\nlines.append(\"\")\nlines.append(\"  label_only (full_trace_label_only_loss):\")\nlines.append(\"    Seed 42 accuracy: 0.285   | exp_id: deepseek_label_only_seed42  [COLLAPSED]\")\nlines.append(\"      accuracy_ci: [0.261, 0.308]  lift: -0.430\")\nlines.append(\"      pass_f1: 0.0  fail_f1: 0.44\")\nlines.append(\"\")\n\n# --- CodeLlama-13B ---\nlines.append(\"--- CodeLlama-13B ---\")\nlines.append(\"\")\nlines.append(\"  exception_only:\")\nlines.append(\"    Seed 42  accuracy: 0.9983  | exp_id: codellama13b_exception_only_seed42\")\nlines.append(\"      accuracy_ci: [0.9958, 1.000]  pass_f1: 0.9988  fail_f1: 0.9971\")\nlines.append(\"    Seed 123 accuracy: 1.0000  | exp_id: codellama13b_exception_only_seed123\")\nlines.append(\"      pass_f1: 1.0  fail_f1: 1.0  n: 1190\")\nlines.append(\"    Seed 456 accuracy: 0.9983  | exp_id: codellama13b_exception_only_seed456\")\nlines.append(\"      pass_f1: 0.9988  fail_f1: 0.9971  n: 1190\")\nlines.append(\"    3-SEED MEAN: 0.9989\")\nlines.append(\"\")\nlines.append(\"  full_trace (canonical tail512, label_only_loss):\")\nlines.append(\"    Seed 42  accuracy: 0.9824  | exp_id: codellama13b_full_trace_tail512_seed42\")\nlines.append(\"      accuracy_ci: [0.9748, 0.9899]  lift: 0.2672  pass_f1: 0.9878  fail_f1: 0.9680\")\nlines.append(\"    Seed 123 accuracy: 0.9824  | exp_id: codellama13b_full_trace_tail512_seed123\")\nlines.append(\"      accuracy_ci: [0.9748, 0.9899]\")\nlines.append(\"    Seed 456 accuracy: 0.9824  | exp_id: codellama13b_full_trace_tail512_seed456\")\nlines.append(\"      NOTE: all 3 seeds identical at 0.9824\")\nlines.append(\"    NOTE: full-seq loss at tail2048 collapsed (0.296); label_only_loss v3 at tail1024 = 0.9824 epoch1\")\nlines.append(\"\")\nlines.append(\"  no_trace:\")\nlines.append(\"    Seed 42 accuracy: 0.7650  | exp_id: codellama13b_no_trace_seed42\")\nlines.append(\"      accuracy_ci: [0.738, 0.787]  lift: 0.050\")\nlines.append(\"      pass_f1: 0.840  fail_f1: 0.590  n: 1190\")\nlines.append(\"\")\nlines.append(\"  VOTA:\")\nlines.append(\"    Seed 42  accuracy: 0.9857  | exp_id: codellama13b_vota_seed42\")\nlines.append(\"      accuracy_ci: [0.9790, 0.9916]  pass_f1: 0.9900  fail_f1: 0.9748\")\nlines.append(\"    Seed 123 accuracy: 0.9891  | exp_id: codellama13b_vota_seed123\")\nlines.append(\"      accuracy_ci: [0.9832, 0.9941]  pass_f1: 0.9924  fail_f1: 0.9809  n: 1190  lift: 0.2739\")\nlines.append(\"\")\nlines.append(\"  ae_only:\")\nlines.append(\"    Seed 42  accuracy: 0.9908  | exp_id: codellama13b_ae_only_seed42\")\nlines.append(\"      accuracy_ci: [0.9849, 0.9958]  pass_f1: 0.9935  fail_f1: 0.9840\")\nlines.append(\"    Seed 123 accuracy: 0.9908  | exp_id: codellama13b_ae_only_seed123\")\nlines.append(\"      accuracy_ci: [0.9849, 0.9958]  pass_f1: 0.9930  fail_f1: 0.9840\")\nlines.append(\"\")\nlines.append(\"  loop_only:\")\nlines.append(\"    Seed 42  accuracy: 0.7706  | exp_id: codellama13b_loop_only_seed42\")\nlines.append(\"      accuracy_ci: [0.7487, 0.7941]  lift: 0.0555  pass_f1: 0.820  fail_f1: 0.670\")\nlines.append(\"    Seed 123 accuracy: 0.7605  | exp_id: codellama13b_loop_only_seed123\")\nlines.append(\"      accuracy_ci: [0.7387, 0.7857]  pass_f1: 0.8078  fail_f1: 0.6823  lift: 0.0454\")\nlines.append(\"    Seed 456 accuracy: 0.7908  | exp_id: codellama13b_loop_only_seed456\")\nlines.append(\"      pass_f1: 0.843  fail_f1: 0.688  n: 1190  lift: 0.0757\")\nlines.append(\"\")\nlines.append(\"  label_only (full_trace_label_only_loss):\")\nlines.append(\"    Seed 42 (v2) accuracy: 0.2849  | exp_id: codellama13b_label_only_seed42_v2  [COLLAPSED]\")\nlines.append(\"      accuracy_ci: [0.2613, 0.3084]  pass_f1: 0.0  fail_f1: 0.4434\")\nlines.append(\"    Seed 123 (v2) accuracy: 'collapsed' | exp_id: codellama13b_label_only_seed123_v2\")\nlines.append(\"\")\n\n# --- Qwen-1.5B ---\nlines.append(\"--- Qwen2.5-Coder-1.5B ---\")\nlines.append(\"\")\nlines.append(\"  exception_only:\")\nlines.append(\"    Seed 42  accuracy: 0.9983  | exp_id: qwen15b_exception_only_seed42\")\nlines.append(\"      accuracy_ci: [0.9958, 1.000]  lift: 0.283  pass_f1: 0.9988  fail_f1: 0.9971\")\nlines.append(\"    Seed 123 accuracy: 0.9983  | exp_id: qwen15b_exception_only_seed123_v2\")\nlines.append(\"      accuracy_ci: [0.9958, 1.000]\")\nlines.append(\"    Seed 456 accuracy: 0.9983  | exp_id: qwen15b_exception_only_seed456\")\nlines.append(\"      seed_comparison: all 3 seeds identical — fully seed-robust\")\nlines.append(\"    3-SEED MEAN: 0.9983 ± 0.0000\")\nlines.append(\"\")\nlines.append(\"  full_trace:\")\nlines.append(\"    Seed 42 (full_trace, no trunc) accuracy: 0.7706  | exp_id: qwen15b_full_trace_seed42\")\nlines.append(\"    Seed 42 (tail512) accuracy: 0.956   | exp_id: qwen15b_full_trace_tail512_seed42\")\nlines.append(\"      accuracy_ci: [0.945, 0.968]  pass_f1: 0.970  fail_f1: 0.920\")\nlines.append(\"    Seed 123 (tail512) accuracy: 0.9765  | exp_id: qwen15b_full_trace_tail512_seed123\")\nlines.append(\"      accuracy_ci: [0.9681, 0.9849]  lift: 0.2613\")\nlines.append(\"    Seed 456 (tail512) accuracy: 0.9672  | exp_id: qwen15b_full_trace_tail512_seed456\")\nlines.append(\"      accuracy_ci: [0.9563, 0.9773]  lift: 0.2521\")\nlines.append(\"\")\nlines.append(\"  no_trace:\")\nlines.append(\"    Seed 42  accuracy: 0.6731  | exp_id: qwen15b_no_trace_seed42\")\nlines.append(\"      pass_f1: 0.7527  fail_f1: 0.518  n: 1190\")\nlines.append(\"    Seed 123 accuracy: 0.7588  | exp_id: qwen15b_no_trace_seed123\")\nlines.append(\"      accuracy_ci: [0.7328, 0.7824]  lift: 0.0437\")\nlines.append(\"      pass_f1: 0.8323  fail_f1: 0.571\")\nlines.append(\"    Seed 456 accuracy: 0.7387  | exp_id: qwen15b_no_trace_seed456\")\nlines.append(\"      pass_f1: 0.8195  fail_f1: 0.5266\")\nlines.append(\"\")\nlines.append(\"  VOTA:\")\nlines.append(\"    Seed 42  accuracy: 0.9958  | exp_id: qwen15b_vota_seed42\")\nlines.append(\"      pass_f1: 0.9971  fail_f1: 0.9926  n: 1190\")\nlines.append(\"    Seed 123 accuracy: 0.9950  | exp_id: qwen15b_vota_seed123\")\nlines.append(\"      ci_95: [0.9908, 0.9983]  pass_f1: 0.9965  fail_f1: 0.9912\")\nlines.append(\"\")\nlines.append(\"  ae_only:\")\nlines.append(\"    Seed 42  accuracy: 0.9908  | exp_id: qwen15b_ae_only_seed42\")\nlines.append(\"      accuracy_ci: [0.9849, 0.9958]  lift: 0.2756  pass_f1: 0.9935  fail_f1: 0.9840\")\nlines.append(\"    Seed 123 accuracy: 0.9857  | exp_id: qwen15b_ae_only_seed123\")\nlines.append(\"      majority_baseline: 0.715  fail_f1: 0.975\")\nlines.append(\"\")\nlines.append(\"  loop_only:\")\nlines.append(\"    Seed 42  accuracy: 0.7832  | exp_id: qwen15b_loop_only_seed42\")\nlines.append(\"      pass_f1: 0.8526  fail_f1: 0.5905\")\nlines.append(\"    Seed 123 accuracy: 0.8109  | exp_id: qwen15b_loop_only_seed123\")\nlines.append(\"      pass_f1: 0.8737  fail_f1: 0.6244\")\nlines.append(\"    Seed 456 accuracy: 0.7920  | exp_id: qwen15b_loop_only_seed456\")\nlines.append(\"      ci_95: [0.768, 0.813]  majority_baseline: 0.715\")\nlines.append(\"\")\nlines.append(\"  label_only (full_trace_label_only_loss):\")\nlines.append(\"    Seed 42 (v2) accuracy: 0.7890  | exp_id: qwen15b_label_only_seed42_v2\")\nlines.append(\"      accuracy_ci: [0.766, 0.812]  pass_f1: 0.860  fail_f1: 0.570\")\nlines.append(\"    Seed 123 (v2) accuracy: 0.8134  | exp_id: qwen15b_label_only_seed123_v2\")\nlines.append(\"      accuracy_ci: [0.7924, 0.8345]  pass_f1: 0.878  fail_f1: 0.602\")\nlines.append(\"    Seed 456 (v2) accuracy: 0.8252  | exp_id: qwen15b_label_only_seed456_v2\")\nlines.append(\"      pass_f1: 0.885  fail_f1: 0.639\")\nlines.append(\"\")\n\nlines.append(\"\")\nlines.append(\"=\" * 100)\nlines.append(\"SECTION 3: TABLE 2 — ABLATION CONDITIONS (Qwen-7B, seed42 canonical)\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\nlines.append(\"--- Ablation: VOTA component decomposition ---\")\nlines.append(\"  ae_only (Qwen-7B seed42) accuracy: 0.9992  CI:[0.9975, 1.0]  | exp_id: vota_ae_only_seed42\")\nlines.append(\"  exception_only (Qwen-7B) accuracy: 0.9983  CI:[0.9958, 1.0]  | exp_id: vota_exception_only_seed42_v2\")\nlines.append(\"  loop_only (Qwen-7B seed42) accuracy: 0.8563  CI:[0.8353, 0.8756]  | exp_id: vota_loop_only_seed42\")\nlines.append(\"  VOTA-no-ae (Qwen-7B seed42) accuracy: 0.9940  CI:[0.989, 0.998]  | exp_id: vota_no_ae_seed42\")\nlines.append(\"    lift_vs_notrace: 0.2430  CI:[0.218, 0.268]\")\nlines.append(\"\")\nlines.append(\"--- Ablation: Exception sub-component ---\")\nlines.append(\"  exc_message_only_seed42: accuracy=0.9950 CI:[0.991, 0.998] | exp_id: exc_message_only_seed42\")\nlines.append(\"    pass_f1: 0.9960  fail_f1: 0.9910  n: 1190\")\nlines.append(\"  exc_stacktrace_only_seed42: accuracy=0.9980 CI:[0.996, 1.0] | exp_id: exc_stacktrace_only_seed42\")\nlines.append(\"    pass_f1: 0.9990  fail_f1: 0.9970  n: 1190\")\nlines.append(\"  exc_type_only_seed42: no metrics (None conclusion)\")\nlines.append(\"\")\nlines.append(\"--- Ablation: full_trace with label_only_loss ---\")\nlines.append(\"  full_trace_label_only_seed42: accuracy=0.8622 CI:[0.8437, 0.8807] | exp_id: full_trace_label_only_seed42\")\nlines.append(\"    lift_vs_notrace: 0.1109 CI:[0.0849, 0.1370]\")\nlines.append(\"    lift_vs_standard_fulltrace: +0.0445 CI:[0.0235, 0.0655] p=0\")\nlines.append(\"    pass_f1: 0.9063  fail_f1: 0.7397\")\nlines.append(\"\")\nlines.append(\"--- Ablation: nomarker (Qwen-7B) ---\")\nlines.append(\"  Seed 42  accuracy: 0.9655  CI:[0.955, 0.976] | exp_id: exception_only_nomarker_seed42\")\nlines.append(\"  Seed 123 accuracy: 0.9832  CI:[0.9756, 0.9899] | exp_id: exception_only_nomarker_seed123\")\nlines.append(\"    pass_f1: 0.9882  fail_f1: 0.9705  lift_over_majority: 0.2681\")\nlines.append(\"  Seed 456 accuracy: 0.9807  CI:[0.9712, 0.9871] | exp_id: exception_only_nomarker_seed456\")\nlines.append(\"    errors: 23  pass_f1: 0.9865  fail_f1: 0.9658  lift_over_majority: 0.2660\")\nlines.append(\"  NOTE: vs exception_only (0.9983), marker contributes ~1.5-3.3pp\")\nlines.append(\"\")\nlines.append(\"--- Ablation: nomarker (Qwen-1.5B) ---\")\nlines.append(\"  qwen15b_nomarker_seed42: accuracy=0.9780 CI:[0.970, 0.986]  | exp_id: qwen15b_nomarker_seed42\")\nlines.append(\"    majority_baseline: 0.715  lift: 0.263\")\nlines.append(\"    pass_precision: 0.970  pass_recall: 1.0  pass_f1: 0.980\")\nlines.append(\"    fail_precision: 1.0    fail_recall: 0.92  fail_f1: 0.960\")\nlines.append(\"\")\nlines.append(\"--- Ablation: exception_only padded to 2048 tokens ---\")\nlines.append(\"  exception_only_padded2048_seed42: accuracy=0.9983  | exp_id: exception_only_padded2048_seed42\")\nlines.append(\"    (identical to unpadded — padding does not degrade accuracy)\")\nlines.append(\"\")\n\nlines.append(\"\")\nlines.append(\"=\" * 100)\nlines.append(\"SECTION 4: TABLE 3 — DENSITY DECOMPOSITION (gradient masking, tail truncation)\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\nlines.append(\"--- Gradient Masking (99.8% masked, exception_only) ---\")\nlines.append(\"  Qwen-7B Seed 42 accuracy: 0.9933 CI:[0.9882, 0.9975] | exp_id: gradient_masking_qwen7b_seed42\")\nlines.append(\"    NOTE: metrics empty (None conclusion) — see seed123/456 for canonical\")\nlines.append(\"  Qwen-7B Seed 123 accuracy: 0.9933 CI:[0.9882, 0.9975] | exp_id: gradient_masking_qwen7b_seed123\")\nlines.append(\"    pass_f1: 0.9953  fail_f1: 0.9883  lift: 0.2782  train_loss: 1.6031  eval_loss: 0.0381\")\nlines.append(\"  Qwen-7B Seed 456 accuracy: 0.9933 CI:[0.9882, 0.9975] | exp_id: gradient_masking_qwen7b_seed456\")\nlines.append(\"    (identical to seed123)\")\nlines.append(\"  3-SEED MEAN: 0.9933 ± 0.0000  dilution_pct: N/A (vs baseline 0.9983 → dilution ~0.5%)\")\nlines.append(\"\")\nlines.append(\"  DeepSeek-6.7B Seed 42 accuracy: 0.9933 CI:[0.9882, 0.9975] | exp_id: deepseek_gradient_masking_seed42\")\nlines.append(\"    dilution_pct: N/A  baseline_accuracy: 99.39%  lift: 0.278  eval_loss: 0.0529\")\nlines.append(\"    majority_baseline: 0.715\")\nlines.append(\"  DeepSeek-6.7B Seed 123 accuracy: 0.9395 | exp_id: deepseek_gradient_masking_seed123\")\nlines.append(\"    pass_precision: 0.924  pass_recall: 0.998  pass_f1: 0.959\")\nlines.append(\"    fail_precision: 0.993  fail_recall: 0.794  fail_f1: 0.882\")\nlines.append(\"    conclusion: negative (fell below 98.5% threshold)\")\nlines.append(\"\")\nlines.append(\"  CodeLlama-13B Seed 42 accuracy: 1.0000 | exp_id: codellama_gradient_masking_seed42\")\nlines.append(\"    accuracy_ci_lower: 1.0  accuracy_ci_upper: 1.0\")\nlines.append(\"    eval_loss: 0.0625  dilution_pct: -0.11  pass_f1: 1.0  fail_f1: 1.0  n_test: 1190\")\nlines.append(\"    baseline_accuracy: 99.89%\")\nlines.append(\"\")\n\nlines.append(\"--- Tail Truncation Budget Curve (Qwen-7B) ---\")\nlines.append(\"  tail-256 (full_trace_tail_256_seed42):  accuracy=0.7748  CI:[0.7496, 0.7975]  pass_f1: 0.8333  fail_f1: 0.6528\")\nlines.append(\"  tail-384 (qwen7b_full_trace_tail384_seed42): accuracy=0.798  CI:[0.776, 0.821]  pass_f1: 0.85  fail_f1: 0.68\")\nlines.append(\"  tail-512 (full_trace_tail_512_seed42):  accuracy=0.9360  CI:[0.922, 0.950]   pass_f1: 0.950  fail_f1: 0.890\")\nlines.append(\"  tail-512 Seed 123 (qwen7b_full_trace_tail512_seed123): accuracy=0.9597 CI:[0.9487, 0.9706]\")\nlines.append(\"  tail-512 Seed 456 (qwen7b_full_trace_tail512_seed456): accuracy=0.9765 CI:[0.9681, 0.9849]\")\nlines.append(\"  tail-1024 (full_trace_tail_1024_seed42): accuracy=0.9647  CI:[0.9546, 0.9748]  pass_f1: 0.9753  fail_f1: 0.9381\")\nlines.append(\"  tail-2048 (full_trace_tail_seed42):     accuracy=0.9730  CI:[0.964, 0.982]    pass_f1: 0.980  fail_f1: 0.950\")\nlines.append(\"  head-2048 (qwen7b_full_trace_head2048_seed42): accuracy=0.8160 (epoch1 best)\")\nlines.append(\"    pass_f1_epoch1: 0.87  fail_f1_epoch1: 0.686\")\nlines.append(\"\")\nlines.append(\"--- Tail Truncation Budget Curve (DeepSeek-6.7B) ---\")\nlines.append(\"  tail-256 (deepseek_full_trace_tail256_seed42):  accuracy=0.7639  CI:[0.7403, 0.7874]  pass_f1: 0.8424  fail_f1: 0.5293\")\nlines.append(\"  tail-384 (deepseek_full_trace_tail384_seed42):  accuracy=0.8070  CI:[0.786, 0.829]    pass_f1: 0.87  fail_f1: 0.60\")\nlines.append(\"  tail-512 (deepseek_full_trace_tail512_seed42):  accuracy=0.9390  CI:[0.926, 0.953]    pass_f1: 0.960  fail_f1: 0.900\")\nlines.append(\"  tail-512 Seed 123 (v2): accuracy=0.9504  CI:[0.9387, 0.9630]\")\nlines.append(\"  tail-512 Seed 456: accuracy=0.9605  CI:[0.9496, 0.9714]\")\nlines.append(\"  tail-1024 (deepseek_full_trace_tail1024_seed42): accuracy=0.9647 CI:[0.9538, 0.9748]  pass_f1: 0.976  fail_f1: 0.936\")\nlines.append(\"  tail-2048 (deepseek_full_trace_tail2048_seed42): accuracy=0.9496 CI:[0.937, 0.962]    pass_f1: 0.965  fail_f1: 0.913\")\nlines.append(\"  head-2048 (deepseek_full_trace_head2048_seed42): accuracy=0.7870 CI:[0.765, 0.810]    pass_f1: 0.850  fail_f1: 0.620\")\nlines.append(\"\")\nlines.append(\"--- Tail Truncation Budget Curve (CodeLlama-13B) ---\")\nlines.append(\"  tail-256 (codellama13b_full_trace_tail256_seed42): accuracy=0.779  CI:[0.757, 0.803]  pass_f1: 0.843  fail_f1: 0.626\")\nlines.append(\"  tail-384 (codellama13b_full_trace_tail384_seed42): accuracy=0.827  CI:[0.807, 0.847]  pass_f1: 0.887  fail_f1: 0.630\")\nlines.append(\"    NOTE: label_only_loss used; conclusion=negative (lower than expected)\")\nlines.append(\"  tail-512 (codellama13b_full_trace_tail512_seed42): accuracy=0.9824 CI:[0.9748, 0.9899]\")\nlines.append(\"    pass_f1: 0.9878  fail_f1: 0.9680  lift: 0.2672  (all 3 seeds identical)\")\nlines.append(\"  tail-1024 (v3, label_only_loss): accuracy_epoch1=0.9824 accuracy_epoch3=0.9756  best_epoch=1\")\nlines.append(\"    pass_f1_epoch1: 0.988  fail_f1_epoch1: 0.968\")\nlines.append(\"  head-2048 (codellama13b_full_trace_head2048_seed42): accuracy=0.7992  CI:[0.7765, 0.8227]\")\nlines.append(\"    pass_f1: 0.8602  fail_f1: 0.6438  lift: 0.084\")\nlines.append(\"\")\nlines.append(\"--- Tail Truncation Budget Curve (Qwen-1.5B) ---\")\nlines.append(\"  tail-256 (qwen15b_full_trace_tail256_seed42):  accuracy=0.7260  CI:[0.700, 0.753]  lift_over_majority: 0.011 (near-0)\")\nlines.append(\"  tail-384 (qwen15b_full_trace_tail384_seed42):  accuracy=0.7361  CI:[0.7101, 0.7622]  lift: 0.021\")\nlines.append(\"  tail-512 (qwen15b_full_trace_tail512_seed42):  accuracy=0.9560  CI:[0.945, 0.968]\")\nlines.append(\"  tail-1024 (qwen15b_full_trace_tail1024_seed42): accuracy=0.966   CI:[0.955, 0.976]   pass_f1: 0.98  fail_f1: 0.94\")\nlines.append(\"  tail-2048 (qwen15b_full_trace_tail2048_seed42): accuracy=0.979   CI:[0.9706, 0.9874]  pass_f1: 0.986  fail_f1: 0.962\")\nlines.append(\"  head-2048 (qwen15b_full_trace_head2048_seed42): accuracy=0.7529  CI:[0.7286, 0.7782]  pass_f1: 0.835  fail_f1: 0.508\")\nlines.append(\"\")\n\nlines.append(\"\")\nlines.append(\"=\" * 100)\nlines.append(\"SECTION 5: REGEX AND MAJORITY BASELINES\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\nlines.append(\"--- Regex Baseline (marker condition) ---\")\nlines.append(\"  exp_id: regex_baseline_analysis  n=1190\")\nlines.append(\"  B1 (ERROR presence):   0.9345\")\nlines.append(\"  B2 (Traceback):        0.7151\")\nlines.append(\"  B3 (any keyword):      0.9345\")\nlines.append(\"  B4 (exception type):   0.9361\")\nlines.append(\"  B5 (format marker):    0.9933  ← best regex, McNemar p=0.041 vs SFT\")\nlines.append(\"  B6 (error count ≥2):   0.9202\")\nlines.append(\"  SFT exception_only:    0.9983\")\nlines.append(\"  Best regex gap vs SFT: -0.0622 (B5 at 99.33%, SFT at 99.83%)\")\nlines.append(\"\")\nlines.append(\"--- Regex Baseline (nomarker condition) ---\")\nlines.append(\"  exp_id: regex_nomarker_baseline  n=1190\")\nlines.append(\"  B5_marker_acc:   0.9933  (original with marker)\")\nlines.append(\"  B5_nomarker_acc: 0.2849  (drops 70.84pp without marker)\")\nlines.append(\"  B5_delta_pp:     -70.84\")\nlines.append(\"  B1_marker_acc:   0.9345\")\nlines.append(\"  B1_nomarker_acc: 0.7151\")\nlines.append(\"  B4_marker_acc:   0.9361\")\nlines.append(\"  B4_nomarker_acc: 0.9361  (unchanged — exception type is format-independent)\")\nlines.append(\"  B5b_nomarker_acc: 0.9345  (alternative regex without marker dependency)\")\nlines.append(\"\")\nlines.append(\"--- Majority Baseline (from experiment metrics) ---\")\nlines.append(\"  majority_baseline across experiments: 0.7151 (standard HumanEval/MBPP split)\")\nlines.append(\"  DebugBench majority_baseline: 0.5141  (50/50 pass/fail)\")\nlines.append(\"  Cross-HE2MBPP majority_baseline: 0.6902\")\nlines.append(\"\")\n\nlines.append(\"\")\nlines.append(\"=\" * 100)\nlines.append(\"SECTION 6: CALIBRATION (ECE / Brier Score)\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\nlines.append(\"--- Qwen-7B calibration across conditions (exp_id: calibration_analysis_seed42, n=1190) ---\")\nlines.append(\"  no_trace:\")\nlines.append(\"    ECE: 0.171476  MCE: 0.475643  Brier: 0.197152  accuracy: 0.751261\")\nlines.append(\"  full_trace:\")\nlines.append(\"    ECE: 0.095817  MCE: 0.249061  Brier: 0.143924  accuracy: 0.817647\")\nlines.append(\"  label_only:\")\nlines.append(\"    ECE: 0.110686  MCE: 0.417124  Brier: 0.120144  accuracy: 0.862185\")\nlines.append(\"  loop_only:\")\nlines.append(\"    ECE: 0.083085  MCE: 0.183406  Brier: 0.118335  accuracy: 0.856303\")\nlines.append(\"  ae_only:\")\nlines.append(\"    ECE: 0.000415  MCE: 0.000415  Brier: 0.000847  accuracy: 0.99916\")\nlines.append(\"  exception_only:\")\nlines.append(\"    ECE: 0.002717  MCE: 0.835484  Brier: 0.001311  accuracy: 0.998319\")\nlines.append(\"  vota:\")\nlines.append(\"    ECE: 0.005410  MCE: 0.622459  Brier: 0.005234  accuracy: 0.994118\")\nlines.append(\"\")\nlines.append(\"--- Cross-model calibration (exp_id: cross_model_calibration_eval, exception_only, n=1190) ---\")\nlines.append(\"  Qwen-7B:\")\nlines.append(\"    ECE: 0.0027  MCE: 0.8355  Brier: 0.0013  accuracy: 0.9983\")\nlines.append(\"  Qwen-1.5B:\")\nlines.append(\"    ECE: 0.0020  MCE: 0.7549  Brier: 0.0013  accuracy: 0.9983\")\nlines.append(\"  CodeLlama-13B:\")\nlines.append(\"    ECE: 0.0020  MCE: 0.0411  Brier: 0.0013  accuracy: 0.9983\")\nlines.append(\"  DeepSeek-6.7B:\")\nlines.append(\"    ECE: 0.0064  MCE: 0.7756  Brier: 0.0061  accuracy: 0.9933\")\nlines.append(\"  ALL: ECE < 0.007, Brier < 0.007 — universally well-calibrated across architectures\")\nlines.append(\"\")\n\nlines.append(\"\")\nlines.append(\"=\" * 100)\nlines.append(\"SECTION 7: CROSS-DATASET GENERALIZATION\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\nlines.append(\"--- HE→MBPP (train HumanEval, test MBPP) ---\")\nlines.append(\"  exception_only (exp_id: cross_he2mbpp_exception_only_seed42):\")\nlines.append(\"    accuracy: 0.9941  majority_baseline: 0.6902  lift: 0.3040\")\nlines.append(\"    pass_f1: 0.9957  fail_f1: 0.9906\")\nlines.append(\"    pass_precision: 0.9980  pass_recall: 0.9936\")\nlines.append(\"    fail_precision: 0.9858  fail_recall: 0.9955\")\nlines.append(\"  no_trace (exp_id: cross_he2mbpp_no_trace_seed42):\")\nlines.append(\"    accuracy: 0.7056  majority_baseline: 0.6902  lift: 0.0155\")\nlines.append(\"    pass_f1: 0.8074  fail_f1: 0.3756\")\nlines.append(\"    pass_precision: 0.7360  pass_recall: 0.8941\")\nlines.append(\"    fail_precision: 0.5478  fail_recall: 0.2857\")\nlines.append(\"\")\nlines.append(\"--- MBPP→HE (train MBPP, test HumanEval) ---\")\nlines.append(\"  exception_only (exp_id: cross_mbpp2he_exception_only_seed42): status=DONE, no metrics in spec\")\nlines.append(\"  no_trace (exp_id: cross_mbpp2he_no_trace_seed42): status=DONE, no metrics in spec\")\nlines.append(\"\")\nlines.append(\"--- Cross-dataset nomarker ablation (HE→MBPP, nomarker) ---\")\nlines.append(\"  exp_id: nomarker_cross_he2mbpp_exception_only\")\nlines.append(\"  accuracy: 0.9546  (vs marker 0.9941 → delta = -0.0395)\")\nlines.append(\"  pass_f1: 0.9662  fail_f1: 0.9309\")\nlines.append(\"  pass_precision: 0.9943  pass_recall: 0.9396\")\nlines.append(\"  fail_precision: 0.8801  fail_recall: 0.9879\")\nlines.append(\"  eval_loss: 1.09  train_loss: 0.247\")\nlines.append(\"  NOTE: even without markers, cross-dataset accuracy ~95.5% (strong generalization)\")\nlines.append(\"\")\n\nlines.append(\"\")\nlines.append(\"=\" * 100)\nlines.append(\"SECTION 8: OUT-OF-DISTRIBUTION (DebugBench)\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\nlines.append(\"  DebugBench exception_only (exp_id: debugbench_exception_only_seed42, n=426):\")\nlines.append(\"    accuracy: 1.0000  CI_wilson:[0.9914, 1.0]  majority_baseline: 0.5141  lift: 0.4859\")\nlines.append(\"    pass_f1: 1.0  fail_f1: 1.0  (zero errors)\")\nlines.append(\"\")\nlines.append(\"  DebugBench VOTA (exp_id: debugbench_vota_seed42, n=426):\")\nlines.append(\"    accuracy: 0.9977  errors: 1  CI:[0.993, 1.0]  majority_baseline: 0.5141  lift: 0.4836\")\nlines.append(\"    pass_f1: 1.0  fail_f1: 1.0\")\nlines.append(\"\")\nlines.append(\"  DebugBench no_trace (exp_id: debugbench_no_trace_seed42):\")\nlines.append(\"    accuracy: 0.9671  majority_baseline: 0.5141  lift: 0.4531\")\nlines.append(\"    pass_f1: 0.967  fail_f1: 0.967\")\nlines.append(\"    CI: [0.948, 0.984]\")\nlines.append(\"  NOTE: no_trace lift is higher on DebugBench because 50/50 class balance\")\nlines.append(\"\")\n\nlines.append(\"\")\nlines.append(\"=\" * 100)\nlines.append(\"SECTION 9: FRONTIER LLM COMPARISON (GPT-4o, GPT-4.1, zero-shot Qwen-7B)\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\nlines.append(\"  GPT-4o 0-shot exception_only (exp_id: fewshot_gpt4o_exception_only_0shot):\")\nlines.append(\"    accuracy: 0.8798  fail_f1: 0.8228\")\nlines.append(\"  GPT-4o 3-shot exception_only (exp_id: fewshot_gpt4o_exception_only_3shot):\")\nlines.append(\"    accuracy: 0.8681  fail_f1: 0.7995  (3-shot worse than 0-shot)\")\nlines.append(\"  GPT-4o 0-shot no_trace (exp_id: fewshot_gpt4o_no_trace_0shot):\")\nlines.append(\"    accuracy: 0.8445  fail_f1: 0.7543\")\nlines.append(\"\")\nlines.append(\"  GPT-4.1 0-shot exception_only (exp_id: fewshot_gpt41_exception_only_0shot):\")\nlines.append(\"    accuracy: 0.8218  fail_f1: 0.7452\")\nlines.append(\"  GPT-4.1 3-shot exception_only (exp_id: fewshot_gpt41_exception_only_3shot):\")\nlines.append(\"    accuracy: 0.8193  fail_f1: 0.7413\")\nlines.append(\"  GPT-4.1 0-shot no_trace (exp_id: fewshot_gpt41_no_trace_0shot):\")\nlines.append(\"    accuracy: 0.7731  fail_f1: 0.6608\")\nlines.append(\"\")\nlines.append(\"  Qwen-7B 0-shot exception_only (exp_id: zeroshot_qwen7b_exception_only):\")\nlines.append(\"    accuracy: 0.8908  CI:[0.8731, 0.9076]  pass_f1: 0.9276  fail_f1: 0.7774  n: 1190\")\nlines.append(\"  Qwen-7B 3-shot exception_only (exp_id: fewshot_qwen7b_exception_only):\")\nlines.append(\"    accuracy: 0.9084  CI:[0.8908, 0.9244]  pass_f1: 0.9368  fail_f1: 0.8336  n: 1190\")\nlines.append(\"  → SFT Qwen-7B exception_only: 0.9983  (gap vs 0-shot: +10.75pp)\")\nlines.append(\"\")\nlines.append(\"  DeepSeek-6.7B 0-shot (exp_id: zeroshot_deepseek7b_exception_only):\")\nlines.append(\"    accuracy: 0.9059  CI:[0.8899, 0.9218]  pass_f1: 0.9313  fail_f1: 0.8507  n: 1190\")\nlines.append(\"  Qwen-1.5B 0-shot (exp_id: zeroshot_qwen15b_exception_only):\")\nlines.append(\"    accuracy: 0.9345  CI:[0.9202, 0.9479]  pass_f1: 0.9690  fail_f1: 0.8730  n: 1190  unknown: 24\")\nlines.append(\"  CodeLlama-13B 0-shot (exp_id: zeroshot_codellama13b_exception_only):\")\nlines.append(\"    accuracy: 0.5101  CI:[0.4824, 0.5395]  pass_f1: 0.5187  fail_f1: 0.5146  n: 1190  unknown: 30\")\nlines.append(\"    NOTE: near-random, heavy bias toward fail\")\nlines.append(\"\")\n\nlines.append(\"\")\nlines.append(\"=\" * 100)\nlines.append(\"SECTION 10: LEARNING DYNAMICS (step-level, Qwen-7B)\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\nlines.append(\"  exception_only dynamics (exp_id: qwen7b_exception_only_dynamics_seed42):\")\nlines.append(\"    step50:  0.9933  step100: 0.9933  step150: 0.9933\")\nlines.append(\"    step200: 0.9983  step250: 0.9983  step300: 0.9983\")\nlines.append(\"    step350: 0.9983  step400: 0.9983  step444: 0.9983\")\nlines.append(\"    saturation_step: 200  final_loss: 0.0329  pass_f1: 0.9988  fail_f1: 0.9971\")\nlines.append(\"\")\nlines.append(\"  full_trace (label_only_loss) dynamics (exp_id: qwen7b_full_trace_dynamics_seed42):\")\nlines.append(\"    step50:  0.8739  step100: 0.821  step150: 0.857\")\nlines.append(\"    step200: 0.866   step250: 0.874  step300: 0.849\")\nlines.append(\"    step350: 0.888   step400: 0.857  step444: 0.882\")\nlines.append(\"    best_step: 350  best_acc: 0.8882  final_loss: 0.0085\")\nlines.append(\"    NOTE: non-monotonic, no saturation (vs exception_only which saturates at step 200)\")\nlines.append(\"\")\n\nlines.append(\"\")\nlines.append(\"=\" * 100)\nlines.append(\"SECTION 11: MISC / COVERAGE NOTES\")\nlines.append(\"=\" * 100)\nlines.append(\"\")\n\nlines.append(\"  attention_gradient_analysis: DONE, no numeric metrics stored\")\nlines.append(\"\")\nlines.append(\"  Qwen-1.5B (earlier alias qwen1.5b_*): all killed — use qwen15b_* experiments\")\nlines.append(\"  CodeLlama (earlier alias codellama_*): all killed — use codellama13b_* experiments\")\nlines.append(\"\")\nlines.append(\"  cross_mbpp2he_exception_only_seed42: DONE, metrics NOT stored in registry\")\nlines.append(\"  cross_mbpp2he_no_trace_seed42: DONE, metrics NOT stored in registry\")\nlines.append(\"\")\nlines.append(\"  Seed-42 canonical for Qwen-7B exception_only NOT separately recorded;\")\nlines.append(\"    accuracy confirmed 0.9983 via seed_comparison fields in seed123 and seed456 records\")\nlines.append(\"\")\nlines.append(\"  codellama_gradient_masking_seed42: accuracy=1.0000 dilution_pct=-0.11 (better than baseline)\")\nlines.append(\"\")\nlines.append(\"  deepseek_gradient_masking summary:\")\nlines.append(\"    seed42: accuracy=0.9933 (success) | seed123: accuracy=0.9395 (negative — below 98.5% threshold)\")\nlines.append(\"\")\n\nlines.append(\"=\" * 100)\nlines.append(\"END OF REGISTRY AUDIT EXTRACT\")\nlines.append(\"=\" * 100)\n\noutput = \"\\n\".join(lines)\nwith open(output_path, 'w') as f:\n    f.write(output)\n\nprint(f\"Written {len(output)} chars / {len(lines)} lines to {output_path}\")\nPYEOF\n",
  "description": "Compile comprehensive audit extract and write to artifacts file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "c509591a-9339-4184-9fd1-29f8a5eefc21",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_01RmrSyVnwGEJUHAURegp8sK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1495,
      "cache_read_input_tokens": 58453,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1495,
        "ephemeral_1h_input_tokens": 0
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

_source line 72 · 2026-05-23T19:23:18.382Z_

<details><summary>↩ Tool result · `toolu_01C9E9JJnSAWMfQ51mMNp4jB`</summary>

```text
Written 30821 chars / 578 lines to /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts/_audit_registry_extract.txt
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "79e0cdcb-e11a-4c07-924e-261fc7f438da"
}
```

</details>

---


### System

_source line 73_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "description": "Running Verify file line count",
  "usage": {
    "total_tokens": 77576,
    "tool_uses": 14,
    "duration_ms": 336895
  },
  "last_tool_name": "Bash",
  "uuid": "d1858204-50c8-400b-b0f6-98eca555a9a5",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool call

_source line 74_

<details open><summary>🔧 Tool call — Bash · `toolu_01AvCnWWKt5ViGRRsSpJRB8J`</summary>

```json
{
  "command": "wc -l /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts/_audit_registry_extract.txt",
  "description": "Verify file line count"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "9a2b1a5b-8837-4ff3-83e4-df3c122a6ca4",
  "message": {
    "model": "claude-sonnet-4-6",
    "id": "msg_015gZsywCJ8Gs9d9Cc28H2yh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 16985,
      "cache_read_input_tokens": 59948,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 16985,
        "ephemeral_1h_input_tokens": 0
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

_source line 75 · 2026-05-23T19:23:22.442Z_

<details><summary>↩ Tool result · `toolu_01AvCnWWKt5ViGRRsSpJRB8J`</summary>

```text
577 /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts/_audit_registry_extract.txt
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "fda620ce-b4b5-4c0d-b10f-7a4baa108a84"
}
```

</details>

---


### System

_source line 76_

```json
{
  "type": "system",
  "subtype": "task_notification",
  "task_id": "ad4eda51cd882ef4e",
  "tool_use_id": "toolu_015nThs5u5v32WJHrbmn69eM",
  "status": "completed",
  "output_file": "",
  "summary": "Parse registry JSON for audit",
  "usage": {
    "total_tokens": 77742,
    "tool_uses": 14,
    "duration_ms": 349227
  },
  "uuid": "1031de21-b764-409f-914b-13bfa15ed421",
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8"
}
```

---


### Tool result

_source line 77 · 2026-05-23T19:23:34.721Z_

<details><summary>↩ Tool result · `toolu_015nThs5u5v32WJHrbmn69eM`</summary>

```text
The audit extract has been written to `/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts/_audit_registry_extract.txt` (577 lines, 30K chars).

**What was extracted from 188 registry experiments:**

**Section 1 — Table 1 (Qwen-7B main conditions):**
- exception_only: 0.9983 ± 0.0000 across all 3 seeds (identical)
- full_trace: ~0.814 mean (seed42=0.8176, seed123=0.8020, seed456=0.8235)
- no_trace: ~0.764 mean (seed42=0.7513, seed123=0.7908, seed456=0.7504)
- VOTA: ~0.991 (seed42_v5=0.9941, seed123=0.9866, seed456=0.9908)
- ae_only: 0.9964 ± 0.0049; loop_only: 0.8605 ± 0.0053

**Section 2 — Cross-model (all 4 architectures × conditions), including all CI bounds**

**Section 3 — Table 2 ablations:** VOTA component decomposition, exception sub-components (message=0.9950, stacktrace=0.9980), nomarker (~0.965–0.983), label_only_loss

**Section 4 — Density/tail truncation curves** for all 4 models (256→384→512→1024→2048 tokens, head vs tail); gradient masking results

**Section 5 — Regex baselines:** B1–B6 exact numbers; B5 nomarker collapse (0.9933→0.2849, -70.84pp)

**Section 6 — ECE/Brier:** All 7 conditions for Qwen-7B; cross-model calibration (all ECE < 0.007)

**Sections 7–11:** Cross-dataset (HE→MBPP, MBPP→HE), DebugBench OOD, GPT-4o/4.1 frontier comparison, learning dynamics, and coverage gaps (cross_mbpp2he has no stored metrics).

agentId: ad4eda51cd882ef4e (use SendMessage with to: 'ad4eda51cd882ef4e' to continue this agent)
&lt;usage>total_tokens: 77651
tool_uses: 14
duration_ms: 349229&lt;/usage>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "467a5ed8-9758-476d-890e-114963e17ab5",
  "tool_use_result": {
    "status": "completed",
    "prompt": "I need you to parse a large JSON registry file and extract all experiment metrics for a paper data audit.\n\nThe file is at: /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-trace-verdict-study/d5f32b76-3066-49a9-b711-4657d91efad8/tool-results/mcp-agent-ml-research-read_registry-1779563834793.txt\n\nIt's JSON with schema: {result: string} — the `result` field is itself a JSON string that needs to be parsed.\n\nPlease use Python to:\n1. Load the file, parse the outer JSON, then parse the inner `result` string\n2. For each experiment, extract: exp_id, status, metrics (especially accuracy, mean, std, seeds, ECE, Brier, CI, etc.), and any tags/labels\n3. Group experiments by their type/condition (e.g., exception_only, full_trace, ae_only, VOTA, loop_only, no_trace, regex, majority, ablation, density/gradient masking, cross-dataset, nomarker, SFT, etc.)\n\nOutput a comprehensive structured summary with ALL numeric metrics for every experiment. I need exact numbers - don't round or summarize. Include exp_id for each.\n\nFocus especially on:\n- Table 1 experiments (cross_model): exception_only, ae_only, VOTA, loop_only, full_trace, no_trace for models GPT-4o, Claude-3.5, Gemini-2.0, DeepSeek-V3\n- Table 2 experiments (ablation): different conditions with accuracy, CI, tier\n- Table 3 experiments (density decomposition): exception_only, gradient masking, full_trace, label-only\n- Regex baseline and Majority baseline numbers\n- Any nomarker experiments\n- Any cross-dataset experiments\n- ECE and Brier score values\n\nWrite the output to /home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts/_audit_registry_extract.txt so I can read it.",
    "agentId": "ad4eda51cd882ef4e",
    "agentType": "general-purpose",
    "content": [
      {
        "type": "text",
        "text": "The audit extract has been written to `/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts/_audit_registry_extract.txt` (577 lines, 30K chars).\n\n**What was extracted from 188 registry experiments:**\n\n**Section 1 — Table 1 (Qwen-7B main conditions):**\n- exception_only: 0.9983 ± 0.0000 across all 3 seeds (identical)\n- full_trace: ~0.814 mean (seed42=0.8176, seed123=0.8020, seed456=0.8235)\n- no_trace: ~0.764 mean (seed42=0.7513, seed123=0.7908, seed456=0.7504)\n- VOTA: ~0.991 (seed42_v5=0.9941, seed123=0.9866, seed456=0.9908)\n- ae_only: 0.9964 ± 0.0049; loop_only: 0.8605 ± 0.0053\n\n**Section 2 — Cross-model (all 4 architectures × conditions), including all CI bounds**\n\n**Section 3 — Table 2 ablations:** VOTA component decomposition, exception sub-components (message=0.9950, stacktrace=0.9980), nomarker (~0.965–0.983), label_only_loss\n\n**Section 4 — Density/tail truncation curves** for all 4 models (256→384→512→1024→2048 tokens, head vs tail); gradient masking results\n\n**Section 5 — Regex baselines:** B1–B6 exact numbers; B5 nomarker collapse (0.9933→0.2849, -70.84pp)\n\n**Section 6 — ECE/Brier:** All 7 conditions for Qwen-7B; cross-model calibration (all ECE < 0.007)\n\n**Sections 7–11:** Cross-dataset (HE→MBPP, MBPP→HE), DebugBench OOD, GPT-4o/4.1 frontier comparison, learning dynamics, and coverage gaps (cross_mbpp2he has no stored metrics)."
      }
    ],
    "totalDurationMs": 349229,
    "totalTokens": 77651,
    "totalToolUseCount": 14,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 164,
      "cache_read_input_tokens": 76933,
      "output_tokens": 553,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 164
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 553,
          "cache_read_input_tokens": 76933,
          "cache_creation_input_tokens": 164,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 164,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "toolStats": {
      "readCount": 0,
      "searchCount": 0,
      "bashCount": 14,
      "editFileCount": 0,
      "linesAdded": 0,
      "linesRemoved": 0,
      "otherToolCount": 0
    }
  }
}
```

</details>

---


### Assistant

_source line 78_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the .tex files and the registry extract. Let me read the registry extract to get the exact numbers for cross-referencing.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "74562036-a49f-4cee-b153-690c6b613dc9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018kDszwPzdowHjBR2QVfUgb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 33784,
      "cache_read_input_tokens": 26782,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 33784
      },
      "output_tokens": 18,
      "service_tier": "standard",
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

_source line 79_

Registry 数据已提取。现在读取详细的 registry 数据来逐项核对。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "9a9a00cf-ca3c-443e-a818-f2b5504fcd9c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018kDszwPzdowHjBR2QVfUgb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 33784,
      "cache_read_input_tokens": 26782,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 33784
      },
      "output_tokens": 18,
      "service_tier": "standard",
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

_source line 80_

<details open><summary>🔧 Tool call — Read · `toolu_013de1tHP1pFJVkMgxMM9EVe`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts/_audit_registry_extract.txt"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d5f32b76-3066-49a9-b711-4657d91efad8",
  "uuid": "e26405cb-d77c-4188-8a80-c6e1b72022fa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018kDszwPzdowHjBR2QVfUgb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 33784,
      "cache_read_input_tokens": 26782,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 33784
      },
      "output_tokens": 18,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---
