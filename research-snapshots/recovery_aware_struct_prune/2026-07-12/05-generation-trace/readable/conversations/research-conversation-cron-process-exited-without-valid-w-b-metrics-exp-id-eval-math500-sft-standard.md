# Research conversation: [CRON] 实验进程异常退出（失败），需要你诊断原因。 详情: Process exited without valid W&B metrics - exp_id: eval_math500_sft_standard_20_fixed_v

**How Pruning Criteria Shape Post-RLVR Recovery: A Controlled Study of Structured MLP Pruning in a Reasoning LLM (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 67
- **Recorded user turns:** 1
- **Tool calls:** 19
- **Original source:** `logs/chats/exported-trajectories/account-1/dc0980c3-5832-4647-951a-4335ba333699.jsonl`
- **Structured JSON:** [`451383d5e8ce3d5f9d71.json`](../../sessions/45/451383d5e8ce3d5f9d71.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-23T21:16:07.375Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-23T21:16:07.375Z",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "content": "[CRON] 实验进程异常退出（失败），需要你诊断原因。\n详情: Process exited without valid W&B metrics\n\n- exp_id: eval_math500_sft_standard_20_fixed_v3\n- project: recovery_aware_struct_prune\n- server: westd-32935\n- log_path: ~/runs/recovery_aware_struct_prune/eval_math500_sft_standard_20_fixed_v3.log"
}
```

---

### Runtime record

_source line 2 · 2026-05-23T21:16:07.383Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-23T21:16:07.383Z",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699"
}
```

---

## Round 1

65 recorded events

### User

_source line 3 · 2026-05-23T21:16:07.434Z_

[CRON] 实验进程异常退出（失败），需要你诊断原因。
详情: Process exited without valid W&B metrics

- exp_id: eval_math500_sft_standard_20_fixed_v3
- project: recovery_aware_struct_prune
- server: westd-32935
- log_path: ~/runs/recovery_aware_struct_prune/eval_math500_sft_standard_20_fixed_v3.log

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "8e0f54eb-0507-470d-94cb-eb9b93be8945",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-23T21:16:07.431Z_

```json
{
  "parentUuid": "8e0f54eb-0507-470d-94cb-eb9b93be8945",
  "isSidechain": false,
  "attachment": {
    "type": "deferred_tools_delta",
    "addedNames": [
      "AskUserQuestion",
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterPlanMode",
      "EnterWorktree",
      "ExitPlanMode",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__allocate_and_submit",
      "mcp__agent-ml-research__append_idea",
      "mcp__agent-ml-research__approve_worker",
      "mcp__agent-ml-research__auto_build_provenance",
      "mcp__agent-ml-research__backup_project_to_s3",
      "mcp__agent-ml-research__cancel_worker",
      "mcp__agent-ml-research__check_job_status",
      "mcp__agent-ml-research__check_paper_consistency",
      "mcp__agent-ml-research__check_provenance_completeness",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__detect_image",
      "mcp__agent-ml-research__distill_papers",
      "mcp__agent-ml-research__edit_paper_section",
      "mcp__agent-ml-research__feishu_read_tum_pending_key",
      "mcp__agent-ml-research__feishu_send_alert",
      "mcp__agent-ml-research__feishu_send_approval_card",
      "mcp__agent-ml-research__feishu_send_result_card",
      "mcp__agent-ml-research__feishu_send_tum_key_request_card",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__get_baseline_metrics",
      "mcp__agent-ml-research__get_distill_status",
      "mcp__agent-ml-research__get_gpu_health",
      "mcp__agent-ml-research__get_image_info",
      "mcp__agent-ml-research__get_matrix_value",
      "mcp__agent-ml-research__get_project_resource_usage",
      "mcp__agent-ml-research__get_tum_config",
      "mcp__agent-ml-research__get_worker_status",
      "mcp__agent-ml-research__impact_analysis",
      "mcp__agent-ml-research__kill_job",
      "mcp__agent-ml-research__list_artifacts",
      "mcp__agent-ml-research__list_available_gpus",
      "mcp__agent-ml-research__list_constraints",
      "mcp__agent-ml-research__list_s3_backups",
      "mcp__agent-ml-research__list_workers",
      "mcp__agent-ml-research__load_project_config",
      "mcp__agent-ml-research__main_agent_post_to_director",
      "mcp__agent-ml-research__matrix_gap_analysis",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__poll_cron",
      "mcp__agent-ml-research__poll_secret_request",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_matrix",
      "mcp__agent-ml-research__read_mistakes",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__reconcile_crons",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__register_cron",
      "mcp__agent-ml-research__request_secret",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__send_progress",
      "mcp__agent-ml-research__spawn_worker",
      "mcp__agent-ml-research__submit_on_allocated",
      "mcp__agent-ml-research__submit_training_job",
      "mcp__agent-ml-research__sync_matrix_status",
      "mcp__agent-ml-research__tail_training_logs",
      "mcp__agent-ml-research__update_baseline",
      "mcp__agent-ml-research__update_matrix",
      "mcp__agent-ml-research__update_registry",
      "mcp__agent-ml-research__verify_references",
      "mcp__agent-ml-research__write_paper_section"
    ],
    "addedLines": [
      "AskUserQuestion",
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterPlanMode",
      "EnterWorktree",
      "ExitPlanMode",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__allocate_and_submit",
      "mcp__agent-ml-research__append_idea",
      "mcp__agent-ml-research__approve_worker",
      "mcp__agent-ml-research__auto_build_provenance",
      "mcp__agent-ml-research__backup_project_to_s3",
      "mcp__agent-ml-research__cancel_worker",
      "mcp__agent-ml-research__check_job_status",
      "mcp__agent-ml-research__check_paper_consistency",
      "mcp__agent-ml-research__check_provenance_completeness",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__detect_image",
      "mcp__agent-ml-research__distill_papers",
      "mcp__agent-ml-research__edit_paper_section",
      "mcp__agent-ml-research__feishu_read_tum_pending_key",
      "mcp__agent-ml-research__feishu_send_alert",
      "mcp__agent-ml-research__feishu_send_approval_card",
      "mcp__agent-ml-research__feishu_send_result_card",
      "mcp__agent-ml-research__feishu_send_tum_key_request_card",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__get_baseline_metrics",
      "mcp__agent-ml-research__get_distill_status",
      "mcp__agent-ml-research__get_gpu_health",
      "mcp__agent-ml-research__get_image_info",
      "mcp__agent-ml-research__get_matrix_value",
      "mcp__agent-ml-research__get_project_resource_usage",
      "mcp__agent-ml-research__get_tum_config",
      "mcp__agent-ml-research__get_worker_status",
      "mcp__agent-ml-research__impact_analysis",
      "mcp__agent-ml-research__kill_job",
      "mcp__agent-ml-research__list_artifacts",
      "mcp__agent-ml-research__list_available_gpus",
      "mcp__agent-ml-research__list_constraints",
      "mcp__agent-ml-research__list_s3_backups",
      "mcp__agent-ml-research__list_workers",
      "mcp__agent-ml-research__load_project_config",
      "mcp__agent-ml-research__main_agent_post_to_director",
      "mcp__agent-ml-research__matrix_gap_analysis",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__poll_cron",
      "mcp__agent-ml-research__poll_secret_request",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_matrix",
      "mcp__agent-ml-research__read_mistakes",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__reconcile_crons",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__register_cron",
      "mcp__agent-ml-research__request_secret",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__send_progress",
      "mcp__agent-ml-research__spawn_worker",
      "mcp__agent-ml-research__submit_on_allocated",
      "mcp__agent-ml-research__submit_training_job",
      "mcp__agent-ml-research__sync_matrix_status",
      "mcp__agent-ml-research__tail_training_logs",
      "mcp__agent-ml-research__update_baseline",
      "mcp__agent-ml-research__update_matrix",
      "mcp__agent-ml-research__update_registry",
      "mcp__agent-ml-research__verify_references",
      "mcp__agent-ml-research__write_paper_section"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "b3373d83-3858-4494-86ad-45d3bdfb8a51",
  "timestamp": "2026-05-23T21:16:07.431Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-23T21:16:07.431Z_

```json
{
  "parentUuid": "b3373d83-3858-4494-86ad-45d3bdfb8a51",
  "isSidechain": false,
  "attachment": {
    "type": "mcp_instructions_delta",
    "addedNames": [
      "agent-ml-research"
    ],
    "addedBlocks": [
      "## agent-ml-research\nML research experiment management tools"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "0dbe3527-36be-4d20-a44f-0748d0595d82",
  "timestamp": "2026-05-23T21:16:07.431Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-23T21:16:07.431Z_

```json
{
  "parentUuid": "0dbe3527-36be-4d20-a44f-0748d0595d82",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "b9120682-70ca-4e21-b424-a8558cb85715",
  "timestamp": "2026-05-23T21:16:07.431Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 7_

```json
{
  "type": "ai-title",
  "aiTitle": "Diagnose W&B metrics missing in failed experiment",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699"
}
```

---

### Assistant

_source line 8 · 2026-05-23T21:16:11.812Z_

<details><summary>Logged reasoning block</summary>

```text
收到实验失败的 CRON 回调。按照 session-start 规范，我需要先初始化，然后按 on-experiment-failed skill 处理。

让我先执行 session-start 初始化，同时加载 on-experiment-failed skill。
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b9120682-70ca-4e21-b424-a8558cb85715",
  "isSidechain": false,
  "requestId": "req_011CbLCEJAaCPFHUzgX6HTEN",
  "type": "assistant",
  "uuid": "efd893d4-5ace-40b7-bd8c-7751ccf7b65d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EHA7NkfzktJFCrWyjBVDdF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25908,
      "cache_read_input_tokens": 11841,
      "output_tokens": 251,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25908,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 251,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 25908,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25908
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Assistant

_source line 9 · 2026-05-23T21:16:12.397Z_

收到实验失败回调，先执行 session-start 初始化，然后诊断失败原因。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "efd893d4-5ace-40b7-bd8c-7751ccf7b65d",
  "isSidechain": false,
  "requestId": "req_011CbLCEJAaCPFHUzgX6HTEN",
  "type": "assistant",
  "uuid": "7ff231e4-aa0c-48ce-a2b2-d53f53cd911d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EHA7NkfzktJFCrWyjBVDdF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25908,
      "cache_read_input_tokens": 11841,
      "output_tokens": 251,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25908,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 251,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 25908,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25908
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 10 · 2026-05-23T21:16:14.271Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01Hz3pS96zFVWXRLGAYmoUFy`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__reconcile_crons,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_roadmap",
  "max_results": 4
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7ff231e4-aa0c-48ce-a2b2-d53f53cd911d",
  "isSidechain": false,
  "requestId": "req_011CbLCEJAaCPFHUzgX6HTEN",
  "type": "assistant",
  "uuid": "56c02ec1-a9f9-4a7a-9977-6db7f1106aa1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EHA7NkfzktJFCrWyjBVDdF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25908,
      "cache_read_input_tokens": 11841,
      "output_tokens": 251,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25908,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 251,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 25908,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25908
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 11 · 2026-05-23T21:16:14.278Z_

<details><summary>↩ Tool result · `toolu_01Hz3pS96zFVWXRLGAYmoUFy`</summary>

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
  "tool_name": "mcp__agent-ml-research__reconcile_crons"
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
  "tool_name": "mcp__agent-ml-research__read_roadmap"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "56c02ec1-a9f9-4a7a-9977-6db7f1106aa1",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "0ef796c5-bcd2-450f-9cfe-b72f6f1bbc7b",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__reconcile_crons",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_roadmap"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__reconcile_crons,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_roadmap",
    "total_deferred_tools": 82
  },
  "sourceToolAssistantUUID": "56c02ec1-a9f9-4a7a-9977-6db7f1106aa1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-23T21:16:26.207Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_012M13so4ypcTdxtWbJBe4Yu`</summary>

```json
{
  "project": "recovery_aware_struct_prune",
  "limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0ef796c5-bcd2-450f-9cfe-b72f6f1bbc7b",
  "isSidechain": false,
  "requestId": "req_011CbLCEoWBDP59vij3jxg4B",
  "type": "assistant",
  "uuid": "94fac28f-68b2-492e-9da3-b78315a77ed6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CdyTGrh7DAxgVUoq9yJwKN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1129,
      "cache_read_input_tokens": 37749,
      "output_tokens": 243,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1129,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 243,
          "cache_read_input_tokens": 37749,
          "cache_creation_input_tokens": 1129,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1129
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-23T21:16:26.250Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__reconcile_crons · `toolu_018vcjbr7JFseeE6HBZ78e9K`</summary>

```json
{}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "94fac28f-68b2-492e-9da3-b78315a77ed6",
  "isSidechain": false,
  "requestId": "req_011CbLCEoWBDP59vij3jxg4B",
  "type": "assistant",
  "uuid": "c8002556-d0ac-4f6b-b948-a435cf9a3b67",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CdyTGrh7DAxgVUoq9yJwKN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1129,
      "cache_read_input_tokens": 37749,
      "output_tokens": 243,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1129,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 243,
          "cache_read_input_tokens": 37749,
          "cache_creation_input_tokens": 1129,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1129
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 14 · 2026-05-23T21:16:26.716Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01JJs5suDw9wbS5uNy9Dg9Xh`</summary>

```json
{
  "project": "recovery_aware_struct_prune",
  "file": "report.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c8002556-d0ac-4f6b-b948-a435cf9a3b67",
  "isSidechain": false,
  "requestId": "req_011CbLCEoWBDP59vij3jxg4B",
  "type": "assistant",
  "uuid": "226f0f1d-58a1-4b93-991e-9f485c647345",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CdyTGrh7DAxgVUoq9yJwKN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1129,
      "cache_read_input_tokens": 37749,
      "output_tokens": 243,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1129,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 243,
          "cache_read_input_tokens": 37749,
          "cache_creation_input_tokens": 1129,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1129
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-23T21:16:26.917Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_roadmap · `toolu_01Hi1FiLe3WgPB9wKyBZLwZf`</summary>

```json
{
  "project": "recovery_aware_struct_prune"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "226f0f1d-58a1-4b93-991e-9f485c647345",
  "isSidechain": false,
  "requestId": "req_011CbLCEoWBDP59vij3jxg4B",
  "type": "assistant",
  "uuid": "6064fb4c-bb7c-40c4-9ecb-73ae01d095fe",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CdyTGrh7DAxgVUoq9yJwKN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1129,
      "cache_read_input_tokens": 37749,
      "output_tokens": 243,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1129,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 243,
          "cache_read_input_tokens": 37749,
          "cache_creation_input_tokens": 1129,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1129
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-23T21:16:27.807Z_

<details><summary>↩ Tool result · `toolu_012M13so4ypcTdxtWbJBe4Yu`</summary>

```text
Error: result (277,936 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune--claude-sessions-agent-853ea75a/dc0980c3-5832-4647-951a-4335ba333699/tool-results/mcp-agent-ml-research-read_registry-1779570987788.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune--claude-sessions-agent-853ea75a/dc0980c3-5832-4647-951a-4335ba333699/tool-results/mcp-agent-ml-research-read_registry-1779570987788.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune--claude-sessions-agent-853ea75a/dc0980c3-5832-4647-951a-4335ba333699/tool-results/mcp-agent-ml-research-read_registry-1779570987788.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "94fac28f-68b2-492e-9da3-b78315a77ed6",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "9590cf61-6d54-4fe8-adc7-7480aefd274f",
  "toolUseResult": "Error: result (277,936 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune--claude-sessions-agent-853ea75a/dc0980c3-5832-4647-951a-4335ba333699/tool-results/mcp-agent-ml-research-read_registry-1779570987788.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune--claude-sessions-agent-853ea75a/dc0980c3-5832-4647-951a-4335ba333699/tool-results/mcp-agent-ml-research-read_registry-1779570987788.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune--claude-sessions-agent-853ea75a/dc0980c3-5832-4647-951a-4335ba333699/tool-results/mcp-agent-ml-research-read_registry-1779570987788.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"eval_math500_sft_standard_20_fixed_v3\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T21:05:21.000Z\", \"updated_at\": \"2026-05-23T21:15:51.935Z\", \"hypothesis\": \"SFT Standard 20% MATH-500 with fixed eval script. v1 crashed at 328/500, v2 killed by timeout (10h too short for ~17h eval). v3 with timeout=20h. P0 method comparison.\", \"conclusion\": \"failed\"}, \"eval_math500_sft_standard_25_fixed_v2\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T21:11:13.760Z\", \"updated_at\": \"2026-05-23T21:11:13.760Z\"}, \"eval_math500_sft_standard_25_fixed\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T15:49:54.395Z\", \"updated_at\": \"2026-05-23T21:11:02.421Z\", \"hypothesis\": \"SFT Standard 25% MATH-500 with fixed eval script. Depends on sft_standard_25_retrain. P1 25% sparsity table.\", \"conclusion\": \"killed\"}, \"eval_math500_sft_standard_20_fixed_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T20:10:23.626Z\", \"updated_at\": \"2026-05-23T21:09:23.483Z\", \"hypothesis\": \"SFT Standard 20% MATH-500 with fixed eval script. Retry of v1 which crashed at 328/500. P0 method comparison.\", \"conclusion\": \"killed\"}, \"eval_math500_sft_random_20_fixed_v2\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T21:05:25.628Z\", \"updated_at\": \"2026-05-23T21:05:25.628Z\"}, \"eval_math500_sft_random_20_fixed\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T15:50:03.335Z\", \"updated_at\": \"2026-05-23T21:05:07.374Z\", \"hypothesis\": \"SFT Random 20% MATH-500 with fixed eval script. Model on westb (sft_random_20). P0 method comparison.\", \"conclusion\": \"killed\"}, \"eval_math500_sft_standard_20_fixed\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T14:42:20.750Z\", \"updated_at\": \"2026-05-23T20:10:08.647Z\", \"hypothesis\": \"SFT Standard 20% MATH-500 with fixed eval script. Replaces OLD v2 (25.8%) and buggy NEW v3 (23.4%) with consistent scoring.\", \"conclusion\": \"failed\"}, \"eval_math500_grpo_cka_only_25_fixed\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T19:48:08.783Z\", \"updated_at\": \"2026-05-23T19:48:29.543Z\", \"hypothesis\": \"GRPO CKA-only 25% MATH-500 with fixed eval script. Model on westd (grpo_cka_only_25). P1 25% sparsity table.\"}, \"eval_math500_sft_rasp_alpha4p0_20_fixed\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T19:48:04.445Z\", \"updated_at\": \"2026-05-23T19:48:27.423Z\", \"hypothesis\": \"SFT RASP α=4.0 20% MATH-500 with fixed eval script. Model on westd (sft_alpha4_20). P1 dose-response table.\"}, \"eval_math500_sft_rasp_alpha2p0_20_fixed\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T19:48:01.183Z\", \"updated_at\": \"2026-05-23T19:48:24.255Z\", \"hypothesis\": \"SFT RASP α=2.0 20% MATH-500 with fixed eval script. Model on westd (sft_rasp_alpha2p0_20). P1 dose-response table.\"}, \"eval_math500_sft_rasp_alpha0p5_20_fixed\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T19:47:56.948Z\", \"updated_at\": \"2026-05-23T19:48:20.868Z\", \"hypothesis\": \"SFT RASP α=0.5 20% MATH-500 with fixed eval script. Model on westd (sft_rasp_alpha0p5_20). P1 dose-response table.\"}, \"eval_math500_sft_cka_only_20_fixed_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T15:44:55.222Z\", \"updated_at\": \"2026-05-23T19:42:45.920Z\", \"hypothesis\": \"SFT CKA-only 20% MATH-500 with fixed eval script. Retry on westb (checkpoint location). Replaces buggy NEW result (26.8%) with consistent scoring.\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.274, \"num_correct\": 137, \"num_total\": 500, \"stderr\": 0.02, \"truncated_pct\": 0.232}}, \"eval_math500_grpo_cka_only_20_fixed\": {\"status\": \"RUNNING\", \"created_at\": \"2026-05-23T15:50:01.329Z\", \"updated_at\": \"2026-05-23T19:35:54.630Z\", \"hypothesis\": \"GRPO CKA-only 20% MATH-500 with fixed eval script. Model on westb (grpo_cka_only_20/checkpoint-100). P0 method comparison.\"}, \"grpo_random_20_retrain_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T16:17:14.338Z\", \"updated_at\": \"2026-05-23T19:25:17.675Z\", \"hypothesis\": \"Retrain GRPO Random 20% from sft_random_20 (100 steps, seed 42). v1 failed: --save_only_model not supported by train_grpo_v5.py. P0 method comparison baseline.\", \"conclusion\": \"success\", \"metrics\": {\"final_reward\": 0.2875, \"final_reward_std\": 0.4291, \"final_loss\": 0.06684, \"final_kl\": 0.004236, \"final_entropy\": 0.1704, \"final_completion_length_mean\": 189.1, \"final_grad_norm\": 5.531, \"frac_reward_zero_std\": 0.4, \"wandb_run_id\": \"9c16hnf7\", \"wandb_run_name\": \"grpo_sft_random_20\", \"training_steps\": 100, \"training_time_hours\": 3.07}}, \"grpo_standard_25_retrain_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T18:50:36.556Z\", \"updated_at\": \"2026-05-23T19:21:20.235Z\", \"hypothesis\": \"Retrain GRPO Standard 25% from sft_standard_25_retrain with correct params (max_completion_length=1024, temp=0.4, rep_penalty=1.15, format_reward=0.1, adamw_bnb_8bit). v1 killed for using defaults (512). Critical path for tab_math500 25% sparsity row.\", \"parent\": \"sft_standard_25_retrain\", \"conclusion\": \"killed\", \"notes\": \"EXIT_CODE=1, log tail shows normal progress at step 23/100 with no traceback. Diagnosis worker dispatched: worker_diagnose_grpo_standard_25_retrain_v2_20260523T192103. fix_worker_id: worker_diagnose_grpo_standard_25_retrain_v2_20260523T192103\"}, \"grpo_rasp_alpha3p0_20_retrain\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T15:49:42.515Z\", \"updated_at\": \"2026-05-23T19:13:21.232Z\", \"hypothesis\": \"Retrain GRPO RASP α=3.0 20% from sft_rasp_alpha3p0_20/checkpoint-935 (100 steps, seed 42). Original checkpoint-100 deleted during disk cleanup. P1 — needed for dose-response table.\", \"notes\": \"Director decision: use default params (max_completion_length=512) to match dose-response internal consistency (α=0.5,2.0,3.0,4.0 all use 512).\"}, \"grpo_random_20_retrain_v3\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T19:12:00.438Z\", \"updated_at\": \"2026-05-23T19:13:18.930Z\", \"hypothesis\": \"Retrain GRPO Random 20% with correct params matching CKA-only/Standard (max_completion_length=1024, temp=0.4, rep_penalty=1.15, format_reward=0.1, adamw_bnb_8bit). v2 used defaults (512), not for paper main table. 100 steps, seed 42. P0 method comparison.\", \"parent\": \"grpo_random_20_retrain_v2\", \"conclusion\": \"killed\", \"notes\": \"Cancelled by Director: v2 results usable with paper disclosure of max_completion_length=512 + conservative estimate argument. No need to retrain with 1024.\"}, \"grpo_standard_25_retrain\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T17:52:21.325Z\", \"updated_at\": \"2026-05-23T18:59:52.748Z\", \"hypothesis\": \"Retrain GRPO Standard 25% from sft_standard_25_retrain (100 steps, seed 42). Old grpo_standard_25 checkpoint on defunct westd-11672. Critical path: tab_math500 25% sparsity row requires this + subsequent MATH-500 fixed eval.\", \"parent\": \"sft_standard_25_retrain\", \"conclusion\": \"failed\", \"notes\": \"Killed: used default max_completion_length=512, need 1024 to match Standard GRPO params. Replaced by grpo_standard_25_retrain_v2.\"}, \"eval_math500_sft_rasp_alpha1p0_20_fixed\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T14:42:23.684Z\", \"updated_at\": \"2026-05-23T18:39:04.256Z\", \"hypothesis\": \"SFT RASP α=1.0 20% MATH-500 with fixed eval script. Replaces buggy NEW result (21.2%) with consistent scoring.\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.216, \"num_correct\": 108, \"num_total\": 500}}, \"eval_math500_grpo_standard_25_fixed\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T17:53:02.953Z\", \"updated_at\": \"2026-05-23T17:53:02.953Z\", \"hypothesis\": \"GRPO Standard 25% MATH-500 with fixed eval script. Depends on grpo_standard_25_retrain. P1 25% sparsity table.\"}, \"grpo_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:42:41.240Z\", \"hypothesis\": \"DeepSeek-R1-Distill-Qwen-7B Standard 25% GRPO (100 steps). 25% Standard 对照，配合 grpo_rasp_25 (frac_zero=0.875)。Parent: sft_standard_25_westd.\", \"metrics\": {\"clipped_ratio\": 0.92, \"collapse_pattern\": \"near_total_collapse\", \"comparison_vs_rasp_25\": \"worse_than_rasp_25(0.009)\", \"kl_final\": 0.0012, \"reward_final\": 0.0075, \"total_steps\": 100, \"wall_clock_min\": 44, \"wandb_run_id\": \"16vqw4e6\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-23T17:52:19.644Z\"}, \"sft_standard_25_retrain\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T15:49:44.201Z\", \"updated_at\": \"2026-05-23T17:28:50.960Z\", \"hypothesis\": \"Retrain SFT Standard 25% from pruned_standard_25 (2 epochs). Original SFT checkpoint deleted during disk cleanup. P1 — needed for 25% sparsity table. pruned_standard_25 confirmed on westd (10.8G).\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.8584, \"token_accuracy\": 0.8, \"steps\": 1870, \"epochs\": 2}}, \"floor_ablation_0p6_cka_only_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T12:10:30.113Z\", \"updated_at\": \"2026-05-23T16:34:08.036Z\", \"hypothesis\": \"Floor ratio ablation retry: floor=0.6, CKA-only 20% pruning. v1 GRPO completed but save_model crashed (disk full). v2 reruns after disk cleanup (168GB freed). Pipeline SKIP mechanism skips Prune+SFT, only reruns GRPO+eval.\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6202, \"gsm8k_correct\": 818, \"gsm8k_total\": 1319, \"gsm8k_ci\": 0.0134, \"eos_rate\": 0.9803, \"avg_response_length\": 252.7, \"grpo_train_loss\": 0.006503, \"grpo_final_reward\": 0.2419}}, \"grpo_random_20_retrain\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T15:49:40.832Z\", \"updated_at\": \"2026-05-23T16:17:06.964Z\", \"hypothesis\": \"Retrain GRPO Random 20% from sft_random_20 (100 steps, seed 42). Original grpo_random_20/checkpoint-100 was deleted during disk cleanup. P0 — needed for method comparison table Random baseline.\", \"conclusion\": \"failed\"}, \"eval_gsm8k_grpo_cka_only_20_verify\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T13:51:49.789Z\", \"updated_at\": \"2026-05-23T16:14:49.034Z\", \"hypothesis\": \"Reproducibility verification of core result: CKA-only 20% GRPO GSM8K accuracy=64.39%. Independent rerun on westb (different server from original westd) to confirm the key number used in Tab 1 and Tab 2.\", \"metrics\": {\"accuracy\": 0.6406, \"n_correct\": 845, \"n_total\": 1319, \"stderr\": 0.0132, \"eos_rate\": 0.9894, \"avg_response_length\": 201.76, \"original_accuracy\": 0.6437, \"accuracy_diff_pp\": -0.31}, \"conclusion\": \"success\"}, \"eval_math500_grpo_alpha3p0_20_fixed\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T15:49:52.706Z\", \"updated_at\": \"2026-05-23T15:49:52.706Z\", \"hypothesis\": \"GRPO RASP α=3.0 20% MATH-500 with fixed eval script. Depends on grpo_rasp_alpha3p0_20_retrain. P1 dose-response table.\"}, \"eval_math500_grpo_random_20_fixed\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-23T15:49:50.962Z\", \"updated_at\": \"2026-05-23T15:49:50.962Z\", \"hypothesis\": \"GRPO Random 20% MATH-500 with fixed eval script. Depends on grpo_random_20_retrain completing first. P0 method comparison table.\"}, \"eval_math500_grpo_rasp_alpha1p0_20_fixed\": {\"status\": \"RUNNING\", \"created_at\": \"2026-05-23T15:44:56.850Z\", \"updated_at\": \"2026-05-23T15:45:42.001Z\", \"hypothesis\": \"GRPO RASP α=1.0 20% MATH-500 with fixed eval script. Replaces buggy NEW result (22.6%) with consistent scoring.\"}, \"eval_math500_grpo_standard_20_fixed\": {\"status\": \"RUNNING\", \"created_at\": \"2026-05-23T14:42:17.751Z\", \"updated_at\": \"2026-05-23T15:23:11.194Z\", \"hypothesis\": \"GRPO Standard 20% MATH-500 with fixed eval script. Replaces OLD v2 (26.4%) with consistently-scored result across all methods.\"}, \"eval_math500_sft_cka_only_20_fixed\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T14:42:14.730Z\", \"updated_at\": \"2026-05-23T15:22:27.687Z\", \"hypothesis\": \"SFT CKA-only 20% MATH-500 with fixed eval script. Replaces buggy NEW result (26.8%) with consistent scoring across all methods.\", \"conclusion\": \"failed\", \"notes\": \"First attempt crashed: checkpoint sft_cka_only_20 does not exist on westd-32935 (only on westb). Must resubmit to westb.\"}, \"eval_math500_grpo_standard_20_fair_2048_v3b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T14:13:47.549Z\", \"updated_at\": \"2026-05-23T14:41:07.038Z\", \"hypothesis\": \"GRPO Standard 20% MATH-500 @2048 with NEW eval script. Restart after v3 was killed. Last pending data point for tab_math500 — needed to ensure all rows use consistent answer extraction.\", \"parent\": \"eval_math500_grpo_standard_20_fair_2048_v2\", \"conclusion\": \"killed\", \"notes\": \"Killed by Director order. v3b used buggy NEW eval script. Director chose Plan A: fix script bugs then re-eval with fixed version. Superseded by eval_math500_grpo_standard_20_fair_fixed.\"}, \"eval_math500_grpo_standard_20_fair_2048_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T13:16:21.853Z\", \"updated_at\": \"2026-05-23T14:17:28.456Z\", \"hypothesis\": \"GRPO Standard 20% MATH-500 @2048 rerun with NEW eval script (pred_answer/gold_answer). Previous v2=26.4% used OLD answer extraction. Rerun ensures consistent comparison with all other MATH-500 evals. Last data point needed to remove ‡ from tab_math500.\", \"parent\": \"eval_math500_grpo_standard_20_fair_2048_v2\", \"conclusion\": \"killed\", \"notes\": \"Killed by Director order. v3 eval script has LaTeX matching bug (overly strict on whitespace/formatting). All MATH-500 evals may revert to OLD script values. GPU westd:2 freed.\"}, \"eval_math500_sft_standard_20_2048_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T06:00:31.430Z\", \"updated_at\": \"2026-05-23T14:11:05.391Z\", \"hypothesis\": \"SFT Standard 20% MATH-500 @2048 rerun with NEW eval script. Previous 25.8% (eval_math500_sft_standard_20_2048_v2) used OLD answer extraction. Rerun ensures consistent comparison with other MATH-500 evals (all NEW version).\", \"parent\": \"eval_math500_sft_standard_20_2048_v2\", \"conclusion\": \"success\", \"notes\": \"Final accuracy=23.4% (117/500) with NEW eval script. Previous premature read was 26.0% (partial file). OLD script (v2) gave 25.8%. Tab_math500 Standard SFT row should use 23.4%.\", \"metrics\": {\"math500_accuracy\": 0.234, \"math500_correct\": 117, \"math500_total\": 500}}, \"floor_ablation_0p5_cka_only_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T09:23:12.274Z\", \"updated_at\": \"2026-05-23T12:48:18.281Z\", \"hypothesis\": \"Floor ratio ablation (retry): floor=0.5, CKA-only 20% pruning on DeepSeek-R1-Distill-Qwen-7B. Pipeline: Prune → SFT(2ep) → GRPO(100 steps) → GSM8K eval. v1 failed during pruning save due to disk full; v2 reruns full pipeline after disk cleanup.\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6171, \"gsm8k_correct\": 814, \"gsm8k_total\": 1319, \"eos_rate\": 0.992}}, \"floor_ablation_0p3_cka_only_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T09:23:27.547Z\", \"updated_at\": \"2026-05-23T12:07:53.712Z\", \"hypothesis\": \"Floor ratio ablation (retry): floor=0.3, CKA-only 20% pruning on DeepSeek-R1-Distill-Qwen-7B. Pipeline: Prune → SFT(2ep) → GRPO(100 steps) → GSM8K eval. v1 failed at GRPO save due to disk full; v2 resumes from completed Prune+SFT, only reruns GRPO+eval.\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6505, \"gsm8k_correct\": 858, \"gsm8k_total\": 1319}}, \"floor_ablation_0p6_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T07:17:30.437Z\", \"updated_at\": \"2026-05-23T12:07:40.404Z\", \"hypothesis\": \"Floor ratio ablation: raising the MLP floor to 0.6 significantly limits pruning freedom (minimum 60% of each layer kept). If accuracy plateaus between 0.5→0.6, it identifies the saturation point of floor parameter. If still improving, suggests the 0.4 default is suboptimal for CKA-only pruning.\", \"conclusion\": \"failed\", \"notes\": \"GRPO training completed (100 steps) but trainer.save_model() crashed due to disk full (safetensors_rust.SafetensorError: No space left on device). GSM8K eval never ran. Need disk cleanup + retry save+eval.\"}, \"eval_gsm8k_postprune_cka_only_30_n1319\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T11:43:05.490Z\", \"updated_at\": \"2026-05-23T11:59:18.899Z\", \"conclusion\": \"killed\", \"notes\": \"Director 取消：post-prune 退化严重，30% 崩溃是定性结论，使用 registry 已有 1.6% 值。\"}, \"eval_postprune_qwen_math_standard_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T11:33:21.029Z\", \"updated_at\": \"2026-05-23T11:34:40.180Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% post-prune GSM8K accuracy. Baseline for comparing CKA-only vs Standard pruning before recovery training on Qwen-Math model.\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.185, \"n_correct\": 37, \"n_total\": 200, \"stderr\": 0.02746, \"eos_rate\": 0.69, \"avg_response_length\": 506.83, \"note\": \"Qwen-Math Standard 20% post-prune = 18.5%. Significantly better than CKA-only (1.0%) at post-prune stage.\"}}, \"eval_postprune_qwen_math_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T11:33:19.445Z\", \"updated_at\": \"2026-05-23T11:34:38.567Z\", \"hypothesis\": \"Qwen2.5-Math-7B CKA-only 20% post-prune GSM8K accuracy. Tests whether CKA-only pruning generalizes from DeepSeek-R1 to Qwen-Math. Low post-prune accuracy expected; key comparison is CKA-only vs Standard post-prune.\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.01, \"n_correct\": 2, \"n_total\": 200, \"stderr\": 0.00704, \"eos_rate\": 0.065, \"avg_response_length\": 958.3, \"note\": \"Qwen-Math CKA-only 20% post-prune = 1.0%. Severe collapse (repetition, gibberish).\"}}, \"eval_gsm8k_grpo_depth_first_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T14:20:41.126Z\", \"updated_at\": \"2026-05-23T11:32:52.439Z\", \"hypothesis\": \"MF5 depth-first GRPO GSM8K eval re-run. Previous pipeline_depth_first_20 results lost due to disk-full during JSON write. GRPO checkpoint intact. Re-running eval to get formal JSON result file. Prior log recovery showed ~24.18% from nohup output.\", \"parent\": \"pipeline_depth_first_20\", \"conclusion\": \"success\", \"metrics\": {\"accuracy_approx\": 0.08, \"note\": \"Early-stopped by Director at ~60-88 samples. Interim accuracy ~8%@50 (GRPO). Prior log recovery showed ~24.18% from nohup output. No JSON result file produced.\", \"early_stopped\": true, \"result_file_on_westb\": false}}, \"eval_gsm8k_sft_depth_first_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T14:20:43.950Z\", \"updated_at\": \"2026-05-23T11:32:50.632Z\", \"hypothesis\": \"MF5 depth-first SFT GSM8K eval. Establishes SFT baseline for depth-first pruning method, paired with GRPO eval to check C1 decoupling for this baseline method.\", \"parent\": \"pipeline_depth_first_20\", \"conclusion\": \"success\", \"metrics\": {\"accuracy_approx\": 0.1, \"note\": \"Early-stopped by Director at ~60-88 samples. Interim accuracy ~10%@50 (SFT). No JSON result file produced.\", \"early_stopped\": true, \"result_file_on_westb\": false}}, \"eval_gsm8k_grpo_random_20_seed123_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T14:22:33.753Z\", \"updated_at\": \"2026-05-23T11:32:48.936Z\", \"hypothesis\": \"MF2 seed123 v2 GSM8K eval (N=1319, greedy, max_new_tokens=2048). 配对 seed42 (50.57%) 和 seed456 (pending). 验证 C1 decoupling 跨 seed 鲁棒性。v1 因 batch_size=1 配置错误作废。\", \"parent\": \"grpo_random_20_seed123_v2\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.5072, \"n_correct\": 669, \"n_total\": 1319, \"stderr\": 0.01377, \"eos_rate\": 0.9939, \"avg_response_length\": 177.9}}, \"eval_math500_grpo_standard_25_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T13:53:43.695Z\", \"updated_at\": \"2026-05-23T11:32:47.334Z\", \"hypothesis\": \"Standard 25% GRPO model MATH-500 @2048 accuracy, expected near-zero due to reward collapse. Re-run with correct max_new_tokens=2048 for consistency with 20% data.\", \"parent\": \"eval_math500_grpo_standard_25\", \"conclusion\": \"negative\", \"metrics\": {\"accuracy\": 0.128, \"n_correct\": 64, \"n_total\": 500, \"truncated\": 326, \"natural_eos\": 174, \"avg_response_length\": 1399.434}}, \"eval_math500_grpo_random_20_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T22:24:42.604Z\", \"updated_at\": \"2026-05-23T11:01:52.883Z\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.134, \"correct\": 67, \"total\": 500, \"stderr\": 0.0152, \"natural_eos\": 167, \"truncated\": 333, \"avg_response_length\": 1479.2}, \"hypothesis\": \"GRPO training on randomly pruned 20% model recovers math reasoning ability measurably above untrained pruned baseline on MATH-500\"}, \"eval_math500_sft_qwen_math_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T23:11:09.017Z\", \"updated_at\": \"2026-05-23T10:44:00.535Z\", \"hypothesis\": \"Qwen2.5-Math-7B CKA-only 20% SFT MATH-500 eval @2048. Cross-architecture validation: if CKA-only criterion generalizes from DeepSeek-R1-Distill to Qwen-Math on MATH-500. SFT GSM8K = 51.5% (N=200). Paired with westb:1 GRPO GSM8K for C1 decoupling cross-arch.\", \"parent\": \"sft_qwen_math_cka_only_20\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.216, \"stderr\": 0.0184, \"correct\": 108, \"total\": 500, \"natural_eos\": 90, \"truncated\": 410, \"avg_response_length\": 1745.338}}, \"eval_math500_grpo_rasp_alpha0p5_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T02:59:15.985Z\", \"updated_at\": \"2026-05-23T10:11:11.002Z\", \"hypothesis\": \"GRPO RASP α=0.5 MATH-500 eval @2048. C1 decoupling on MATH-500: SFT α=0.5 = 25.4%. GSM8K GRPO α=0.5 = 61.18%. Completes MATH-500 GRPO dose-response curve.\", \"parent\": \"eval_gsm8k_grpo_alpha0p5_20\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.248, \"stderr\": 0.0193, \"correct\": 124, \"total\": 500, \"natural_eos\": 274, \"truncated\": 226, \"avg_response_length\": 1110.462}}, \"floor_ablation_0p3_cka_only_20\": {\"status\": \"ALLOCATED\", \"created_at\": \"2026-05-23T07:17:24.674Z\", \"updated_at\": \"2026-05-23T09:20:33.839Z\", \"hypothesis\": \"Floor ratio ablation: lowering the MLP floor from 0.4 to 0.3 allows more aggressive pruning of unimportant layers while CKA-only criterion preserves critical structure. If floor=0.3 maintains GSM8K accuracy within 2pp of floor=0.4 baseline, it demonstrates robustness of CKA-guided pruning to floor choice.\", \"conclusion\": \"failed\", \"notes\": \"磁盘满导致 GRPO save_model 失败。Prune ✅ SFT ✅ GRPO 训练100/100完成但模型保存崩溃(safetensors No space left)。grpo_cka_only_20_floor_0.3/ 有 4.8GB 不完整文件需删除后重跑 GRPO step。\"}, \"floor_ablation_0p5_cka_only_20\": {\"status\": \"ALLOCATED\", \"created_at\": \"2026-05-23T07:17:27.612Z\", \"updated_at\": \"2026-05-23T09:18:25.276Z\", \"hypothesis\": \"Floor ratio ablation: raising the MLP floor from 0.4 to 0.5 constrains pruning to be more conservative. If floor=0.5 improves GSM8K accuracy over floor=0.4, it suggests CKA-only criterion benefits from a higher minimum layer size. Maps the sensitivity curve of floor parameter on recovery quality.\", \"conclusion\": \"failed\", \"notes\": \"磁盘满 (650G/650G) 导致崩溃。需清理后重新提交。\"}, \"eval_math500_grpo_cka_only_20_2048_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T05:07:09.002Z\", \"updated_at\": \"2026-05-23T08:55:58.278Z\", \"hypothesis\": \"GRPO CKA-only 20% MATH-500 @2048 rerun with NEW eval script. Previous 29.2% (eval_math500_grpo_cka_only_20_2048) used OLD answer extraction. SFT CKA-only = 26.8% (NEW). Rerun ensures consistent C1 |Δ| comparison.\", \"parent\": \"eval_math500_grpo_cka_only_20_2048\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.274, \"correct\": 137, \"total\": 500, \"stderr\": 0.01995, \"natural_eos\": 390, \"truncated\": 110, \"avg_response_length\": 654.746}}, \"eval_math500_grpo_rasp_alpha3p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T03:19:40.950Z\", \"updated_at\": \"2026-05-23T07:48:57.618Z\", \"hypothesis\": \"GRPO RASP α=3.0 MATH-500 eval @2048. C1 decoupling on MATH-500: SFT α=3.0 = 23.2%. GSM8K GRPO α=3.0 = 63.45%. Completes MATH-500 GRPO dose-response curve for α=3.0 data point.\", \"parent\": \"eval_gsm8k_grpo_alpha3p0_20\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.228, \"correct\": 114, \"total\": 500, \"stderr\": 0.0188, \"truncated_ratio\": 0.28, \"avg_response_length\": 745.038}}, \"eval_math500_grpo_rasp_alpha4p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-23T00:01:54.194Z\", \"updated_at\": \"2026-05-23T05:58:52.769Z\", \"hypothesis\": \"GRPO RASP α=4.0 MATH-500 eval @2048. C1 decoupling on MATH-500: SFT α=4.0 = 26.6%. If |GRPO - SFT| < 2pp, C1 decoupling holds cross-benchmark for α=4.0. GSM8K GRPO α=4.0 = 62.77%.\", \"parent\": \"eval_gsm8k_grpo_alpha4_20_v3\", \"metrics\": {\"accuracy\": 0.262, \"stderr\": 0.01966, \"correct\": 131, \"total\": 500, \"truncated\": 180, \"natural_eos\": 320, \"avg_response_length\": 925.48}, \"conclusion\": \"success\"}, \"eval_math500_grpo_rasp_alpha1p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T23:02:44.335Z\", \"updated_at\": \"2026-05-23T04:44:32.303Z\", \"hypothesis\": \"GRPO RASP α=1.0 MATH-500 eval @2048. C1 decoupling on MATH-500: SFT α=1.0 = 21.2%. If |GRPO - SFT| < 2pp, C1 decoupling holds cross-benchmark for α=1.0.\", \"metrics\": {\"accuracy\": 0.226, \"stderr\": 0.0187, \"n_correct\": 113, \"n_total\": 500, \"avg_response_length\": 903.536, \"natural_eos\": 320, \"truncated\": 180}, \"conclusion\": \"success\"}, \"eval_math500_sft_cka_only_20_westd\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T20:45:21.526Z\", \"updated_at\": \"2026-05-23T03:21:26.164Z\", \"hypothesis\": \"CKA-only 20% SFT MATH-500 eval @2048 on westd (migrated from westb for speed). Dose-response endpoint control: CKA-only is the best-performing pruning method (GSM8K 64.37%). MATH-500 result establishes upper bound for cross-benchmark dose-response curve.\", \"parent\": \"eval_math500_sft_cka_only_20_westb\", \"metrics\": {\"accuracy\": 0.268, \"correct\": 134, \"total\": 500, \"truncated\": 116, \"stderr\": 0.0198, \"natural_eos_pct\": 0.768, \"avg_response_length\": 673.278, \"note\": \"PID 75284 actual output = 26.8% (134/500). Previous 29.0% (145/500) was from v4 run (May 19) with different answer extraction. Same model generations, different scoring.\"}, \"conclusion\": \"success\"}, \"eval_math500_grpo_rasp_alpha2p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T22:23:27.589Z\", \"updated_at\": \"2026-05-23T03:16:40.537Z\", \"hypothesis\": \"GRPO RASP α=2.0 MATH-500 eval @2048. C1 decoupling evidence on MATH-500: SFT α=2.0 = 24.0%, GRPO expected similar (~24%). If |GRPO - SFT| < 1pp, C1 decoupling holds cross-benchmark.\", \"metrics\": {\"accuracy\": 0.262, \"correct\": 131, \"total\": 500, \"stderr\": 0.0197, \"natural_eos\": 349, \"truncated\": 151, \"avg_response_length\": 785.326}, \"conclusion\": \"success\"}, \"eval_gsm8k_grpo_qwen_math_cka_only_20_n500_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T15:12:46.181Z\", \"updated_at\": \"2026-05-23T02:53:37.071Z\", \"hypothesis\": \"MF3 cross-architecture validation v3 (N=500, max_new_tokens=2048): Qwen2.5-Math-7B CKA-only 20% GRPO GSM8K eval with absolute model_path fix. v2 crashed due to relative path OSError. v1 killed due to 337s/sample (no token limit). Tests whether CKA-only pruning + GRPO recovery generalizes beyond DeepSeek-R1-Distill to Qwen-Math architecture.\", \"parent\": \"eval_gsm8k_grpo_qwen_math_cka_only_20_n500_v2\", \"metrics\": {\"accuracy\": 0.486, \"correct\": 243, \"total\": 500, \"stderr\": 0.0224, \"truncated_pct\": 0.838, \"natural_eos_pct\": 0.162, \"avg_response_length\": 1766.5}, \"conclusion\": \"success\"}, \"eval_gsm8k_sft_qwen_math_cka_only_20_n500\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T23:11:55.970Z\", \"updated_at\": \"2026-05-22T23:16:17.233Z\", \"hypothesis\": \"MF3 C1 decoupling on Qwen-Math: SFT endpoint (sft_qwen_math_cka_only_20_final, 2 epochs) GSM8K N=500 @2048. Paired with GRPO eval (running westb:1 N=500). Previous SFT eval (51.5% N=200) used checkpoint-935 (epoch 1), not the final model that GRPO was built on. Must eval the correct SFT endpoint for fair C1 comparison.\", \"parent\": \"sft_qwen_math_cka_only_20_v2\", \"conclusion\": \"failed\"}, \"eval_math500_sft_rasp_alpha1p0_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T20:50:24.239Z\", \"updated_at\": \"2026-05-22T23:01:03.419Z\", \"hypothesis\": \"α=1.0 SFT MATH-500 eval @2048 v2 (on westb). Default RASP α=1.0. Cross-benchmark dose-response: GSM8K α=1.0 SFT=63.31%. v1 killed at 304/500, result file never written. Completes 5-point dose-response curve on MATH-500.\", \"parent\": \"eval_math500_sft_rasp_alpha1p0_20\", \"notes\": \"westb submission failed: model sft_rasp_20_westd not found on westb. Only exists on westd-32935. Waiting for westd:3 (α=4.0, 85%) to free up.\", \"metrics\": {\"accuracy\": 0.212, \"correct\": 106, \"total\": 500, \"truncated\": 186, \"stderr\": 0.0183}, \"conclusion\": \"success\"}, \"E_MATH500_SFT_QWEN_CKA\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T22:25:31.683Z\", \"updated_at\": \"2026-05-22T22:48:58.113Z\", \"hypothesis\": \"CKA-guided pruned Qwen2.5-Math-7B after SFT recovery retains competitive MATH-500 performance, validating cross-architecture generalization of the CKA pruning criterion beyond Qwen2.5-Coder.\", \"conclusion\": \"failed\"}, \"eval_math500_grpo_random_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T13:59:40.515Z\", \"updated_at\": \"2026-05-22T22:25:11.246Z\", \"hypothesis\": \"Random 20% GRPO model MATH-500 @2048 accuracy for cross-method comparison with CKA-only and Standard at 20% sparsity\", \"parent\": \"eval_math500_grpo_random_20\", \"conclusion\": \"negative\", \"notes\": \"失败原因: westd-29022 服务器宕机，进程异常退出无 W&B metrics。基础设施故障，需服务器恢复后重新提交。\", \"metrics\": {\"accuracy\": 0.12, \"n_correct\": 60, \"n_total\": 500, \"stderr\": 0.0145, \"note\": \"JSON not saved due to IsADirectoryError but log has full data\"}}, \"eval_math500_grpo_random_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T10:23:18.853Z\", \"updated_at\": \"2026-05-22T22:24:47.948Z\", \"hypothesis\": \"GRPO Random 20% MATH-500 eval @2048. Complement MATH-500 GRPO column. SFT Random 20% = 14.4%. Tests whether GRPO provides recovery benefit for worst-performing pruning method on harder benchmark.\", \"parent\": \"eval_gsm8k_grpo_random_20_v2\", \"conclusion\": \"killed\"}, \"eval_math500_sft_standard_20_2048_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T01:34:44.782Z\", \"updated_at\": \"2026-05-22T22:19:38.080Z\", \"hypothesis\": \"Standard (random) 20% SFT MATH-500 eval @2048. Baseline comparison: Standard pruning without CKA guidance. Cross-benchmark extension of GSM8K Standard results.\", \"parent\": \"eval_math500_sft_standard_20\", \"metrics\": {\"accuracy\": 0.258, \"n_correct\": 129, \"n_total\": 500}, \"conclusion\": \"success\"}, \"eval_math500_sft_rasp_alpha0p5_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T15:20:44.460Z\", \"updated_at\": \"2026-05-22T22:18:43.350Z\", \"hypothesis\": \"α=0.5 SFT MATH-500 eval @2048. Cross-benchmark dose-response validation: GSM8K shows α=0.5 SFT=60.73%. If MATH-500 also shows α=0.5 < α=2.0, inverted-U generalizes beyond GSM8K (strengthens MF4 + N1).\", \"metrics\": {\"accuracy\": 0.254, \"correct\": 127, \"total\": 500, \"truncated\": 220, \"stderr\": 0.0195}, \"conclusion\": \"success\"}, \"eval_math500_sft_rasp_alpha3p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T18:26:16.273Z\", \"updated_at\": \"2026-05-22T22:12:26.406Z\", \"hypothesis\": \"α=3.0 SFT MATH-500 eval @2048. Dose-response \\\"下降段确认点\\\": GSM8K α=3.0 SFT=64.14% (below α=2.0 peak 64.97%). If MATH-500 also shows α=3.0 < α=2.0, confirms inverted-U descending arm cross-benchmark. Completes 5/5 MATH-500 dose-response.\", \"metrics\": {\"accuracy\": 0.232, \"correct\": 116, \"total\": 500, \"truncated\": 144, \"stderr\": 0.0189}, \"conclusion\": \"success\"}, \"eval_math500_sft_rasp_alpha4p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T15:20:47.150Z\", \"updated_at\": \"2026-05-22T21:22:35.441Z\", \"hypothesis\": \"α=4.0 SFT MATH-500 eval @2048. Cross-benchmark dose-response validation: GSM8K shows α=4.0 SFT=61.94%. If MATH-500 also shows α=4.0 < α=2.0, inverted-U generalizes beyond GSM8K (strengthens MF4 + N1).\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.266, \"correct\": 133, \"total\": 500, \"truncated\": 190, \"stderr\": 0.0198}}, \"eval_math500_sft_cka_only_20_westb\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T18:27:25.380Z\", \"updated_at\": \"2026-05-22T20:44:55.638Z\", \"hypothesis\": \"CKA-only 20% SFT MATH-500 eval @2048 on westb. Dose-response endpoint control: CKA-only is the best-performing pruning method (GSM8K 64.37%). MATH-500 result establishes upper bound for cross-benchmark comparison with α dose-response curve.\", \"conclusion\": \"killed\", \"notes\": \"Killed at 51% (255/500) for migration to westd:1 (westb too slow: 2.6min/sample vs ~40-70s on westd). Replaced by eval_math500_sft_cka_only_20_westd.\"}, \"eval_math500_sft_rasp_alpha2p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T15:06:22.386Z\", \"updated_at\": \"2026-05-22T20:44:52.970Z\", \"hypothesis\": \"α=2.0 SFT MATH-500 eval @2048. Dose-response peak on GSM8K (64.97% SFT). Cross-benchmark validation: if α=2.0 also peaks on MATH-500, inverted-U generalizes beyond GSM8K (strengthens MF4 + N1).\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.24, \"correct\": 120, \"total\": 500, \"truncated\": 155, \"stderr\": 0.0191}}, \"eval_gsm8k_grpo_random_20_seed456\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T16:26:01.516Z\", \"updated_at\": \"2026-05-22T18:27:22.282Z\", \"hypothesis\": \"MF2 seed456 GSM8K eval (N=1319, greedy, max_new_tokens=2048). Paired with seed42 (50.57%) and seed123 v2 (running, interim 52.40%@1000). Validates C1 decoupling robustness across random seeds.\", \"parent\": \"grpo_random_20_seed456\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.5087, \"gsm8k_accuracy_se\": 0.0138, \"gsm8k_correct\": 671, \"gsm8k_total\": 1319, \"eos_rate\": 0.9954, \"avg_response_length\": 163.5, \"truncated\": 6}, \"notes\": \"Cron 误判 (已知模式): 实验实际完成 1319/1319, acc=50.87%. 与 seed42 (50.57%) 一致, 验证 C1 decoupling. Results: /root/autodl-tmp/recovery_aware_struct_prune/results/eval_gsm8k_grpo_random_20_seed456.json\"}, \"eval_math500_sft_rasp_alpha1p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T16:49:47.591Z\", \"updated_at\": \"2026-05-22T18:07:37.221Z\", \"hypothesis\": \"α=1.0 SFT MATH-500 eval @2048. Cross-benchmark dose-response: GSM8K α=1.0 SFT=61.49%. With α=0.5/2.0/4.0 MATH-500 already running, this completes 4/5 dose-response points on MATH-500 to validate inverted-U cross-benchmark.\", \"conclusion\": \"killed\"}, \"grpo_random_20_seed456\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T12:00:38.940Z\", \"updated_at\": \"2026-05-22T16:27:46.810Z\", \"hypothesis\": \"MF2 multi-seed validation: Random pruning 20% GRPO with seed456. Third seed for C1 decoupling robustness check. seed42: Δ=-0.68pp, seed123: pending eval. If all seeds show |Δ(GRPO-SFT)| ≤ 2pp, C1 claim is robust across random seeds.\", \"conclusion\": \"success\", \"notes\": \"失败原因: GRPO 训练 100/100 步已完成 (3h02min)，但 save_pretrained 时磁盘满 (No space left on device, os error 28)。保存路径: /root/autodl-tmp/recovery_aware_struct_prune/grpo_random_20_seed456。W&B run auv9riek 有完整训练 metrics。save_steps=100=max_steps，无中间 checkpoint，需重跑。 | 已有成果: W&B metrics 完整 | 建议: 清理 westb-23072 磁盘后重提交\"}, \"eval_gsm8k_grpo_qwen_math_cka_only_20_n500_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T14:31:01.344Z\", \"updated_at\": \"2026-05-22T15:08:28.688Z\", \"hypothesis\": \"MF3 cross-architecture validation v2 (N=500, max_new_tokens=2048): Qwen2.5-Math-7B CKA-only 20% GRPO GSM8K eval. v1 killed due to 337s/sample (no token limit, model generating to 4096). v2 adds max_new_tokens=2048 to constrain generation length.\", \"parent\": \"grpo_qwen_math_cka_only_20\", \"conclusion\": \"failed\"}, \"grpo_random_20_seed123_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T14:22:29.868Z\", \"updated_at\": \"2026-05-22T15:00:23.101Z\", \"hypothesis\": \"MF2 multi-seed validation v2: Random 20% GRPO with seed123, correct batch_size=2 (matching seed42/seed456). v1 used batch_size=1 (half data per 100 steps), results invalidated. Tests C1 decoupling robustness across random seeds.\", \"parent\": \"grpo_random_20_seed123\", \"conclusion\": \"success\"}, \"eval_gsm8k_grpo_alpha3p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T09:30:06.630Z\", \"updated_at\": \"2026-05-22T14:47:06.188Z\", \"hypothesis\": \"α=3.0 GRPO GSM8K eval. Dose-response 5th data point: α=3.0 between α=2.0 (66.11%) and α=4.0 (62.77%). Completes the 5-point dose-response curve for causal evidence of CKA overlap suppression effect.\", \"notes\": \"UNBLOCKED: grpo_rasp_alpha3p0_20_v2 checkpoint-100 完整 (12.3GB). Eval 已启动 PID 43755 on westd:0, 2.8s/sample, ETA ~60 min.\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6345, \"correct\": 837, \"total\": 1319, \"stderr\": 0.0133, \"eos_rate\": 0.9864, \"truncated\": 18, \"avg_response_length\": 219.7}}, \"eval_gsm8k_grpo_random_20_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T11:22:20.913Z\", \"updated_at\": \"2026-05-22T14:38:29.147Z\", \"hypothesis\": \"MF2 multi-seed validation: Random 20% GRPO seed123 GSM8K eval (N=1319, greedy, max_new_tokens=2048). Paired with eval_gsm8k_grpo_random_20 (seed42, 50.57%). If seed123 result within ±2pp of seed42, C1 decoupling claim is robust across random seeds.\", \"parent\": \"grpo_random_20_seed123\", \"notes\": \"⚠️ 结果作废：v1 GRPO 训练用了 batch_size=1（seed42/seed456 都是 batch_size=2），100步只看了一半数据，结果不可比。v2 重训已启动 (grpo_random_20_seed123_v2)。当前 eval 让它跑完（不浪费 GPU），但结果不用于 MF2 论文。\", \"conclusion\": \"killed\", \"metrics\": {\"gsm8k_accuracy\": 0.5125, \"correct\": 676, \"total\": 1319, \"stderr\": 0.0138, \"eos_rate\": 0.992, \"truncated\": 10, \"avg_response_length\": 184.2, \"note\": \"INVALIDATED - v1 GRPO trained with batch_size=1, results not comparable\"}}, \"eval_gsm8k_grpo_qwen_math_cka_only_20_n500\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T12:06:51.067Z\", \"updated_at\": \"2026-05-22T14:30:51.664Z\", \"hypothesis\": \"MF3 cross-architecture validation (N=500 version): Qwen2.5-Math-7B CKA-only 20% GRPO GSM8K eval. Reduced from N=1319 to N=500 for feasibility (78s/sample). CI ±4.4pp sufficient for cross-architecture signal. Intermediate data at N=50: acc=46.0%.\", \"parent\": \"grpo_qwen_math_cka_only_20\", \"conclusion\": \"killed\"}, \"eval_math500_sft_random_20_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T04:11:52.462Z\", \"updated_at\": \"2026-05-22T14:10:18.359Z\", \"hypothesis\": \"Random 20% SFT MATH-500 @2048. v2 failed due to old eval_math500.py on westd-32935. Code synced from westb.\", \"parent\": \"eval_math500_sft_random_20_v2\", \"metrics\": {\"accuracy\": 0.144, \"correct\": 72, \"total\": 500, \"stderr\": 0.0157, \"natural_eos\": 171, \"truncated\": 329, \"avg_response_length\": 1470.44}, \"conclusion\": \"success\"}, \"eval_gsm8k_sft_alpha3p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T10:24:58.696Z\", \"updated_at\": \"2026-05-22T12:38:25.600Z\", \"hypothesis\": \"α=3.0 SFT GSM8K eval (checkpoint-935, 1 epoch). Dose-response 5th SFT data point for C1 decoupling. Paired with α=3.0 GRPO (pending). Completes the 5-point dose-response SFT column.\", \"parent\": \"grpo_rasp_alpha3p0_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6414, \"gsm8k_correct\": 846, \"gsm8k_total\": 1319, \"gsm8k_stderr\": 0.0132, \"eos_rate\": 0.9879, \"avg_response_length\": 188.63, \"natural_eos\": 1303, \"truncated\": 16}, \"notes\": \"Cron 误判。评估 1319/1319 全部完成，accuracy=64.14%。进程因写结果 JSON 时磁盘满 (OSError: No space left on device) 以非零码退出，但所有推理已完成、accuracy 已计算。结果 JSON 未写入磁盘，数据从日志提取。中间进度 ~64.15%@1300 与最终 64.14% 一致。\"}, \"eval_gsm8k_grpo_qwen_math_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T09:30:10.266Z\", \"updated_at\": \"2026-05-22T12:08:34.874Z\", \"hypothesis\": \"MF3 cross-architecture validation: Qwen2.5-Math-7B CKA-only 20% pruned → SFT → GRPO → GSM8K eval. Tests if CKA-guided pruning advantage transfers to Qwen-Math architecture.\", \"parent\": \"grpo_qwen_math_cka_only_20\", \"notes\": \"KILLED: Director 批准 kill (78s/sample too slow, 26.5h ETA). 重启为 N=500 版本 (eval_gsm8k_grpo_qwen_math_cka_only_20_n500). 中间数据: 96/1319, acc=46.0%@50, EOS=14%, avg_len=1805.\", \"conclusion\": \"killed\"}, \"grpo_rasp_alpha3p0_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T10:40:19.362Z\", \"updated_at\": \"2026-05-22T11:58:15.586Z\", \"hypothesis\": \"Re-run of grpo_rasp_alpha3p0_20 (checkpoint corrupted by disk-full). α=3.0 GRPO 100 steps on sft_rasp_alpha3p0_20/checkpoint-935. Critical for dose-response curve (α=3.0 between α=2.0 peak and α=4.0 decline).\", \"parent\": \"grpo_rasp_alpha3p0_20\", \"conclusion\": \"success\"}, \"eval_math500_grpo_standard_20_fair_2048_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T03:49:45.575Z\", \"updated_at\": \"2026-05-22T11:17:52.493Z\", \"hypothesis\": \"Standard 20% fair GRPO MATH-500 @2048. P0 data gap for cross-method MATH-500 table. Re-run on westd-32935 after westd-29022 outage.\", \"parent\": \"eval_math500_grpo_standard_20_fair_2048\", \"conclusion\": \"success\", \"metrics\": {\"math500_accuracy\": 0.264, \"math500_correct\": 132, \"math500_total\": 500, \"math500_stderr\": 0.0197}, \"notes\": \"Cron 误判。实际正常完成。MATH-500 Accuracy = 0.2640 ± 0.0197 (132/500)。运行时长 ~7h11min。结果文件: /root/recovery_aware_struct_prune/results/eval_math500_grpo_standard_20_fair_2048_v2.json\"}, \"grpo_random_20_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T10:34:12.100Z\", \"updated_at\": \"2026-05-22T11:17:21.388Z\", \"hypothesis\": \"MF2 multi-seed validation: Random pruning 20% GRPO with seed123. Tests if GRPO decoupling result (C1) is robust across random seeds. If variance across seeds is low (±2pp), C1 claim is strengthened.\", \"conclusion\": \"success\", \"notes\": \"Cron 误判 (已知 pattern: process dead 5× with no sentinel/W&B)。实际 GRPO 训练正常完成 (19:02 CST)。模型保存: /root/autodl-tmp/recovery_aware_struct_prune/grpo_random_20_seed123。WandB run: grpo_sft_random_20 (ID: 1silchcm)。日志: /tmp/mf2_random_seed123_grpo.log\"}, \"pipeline_depth_first_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T10:31:01.602Z\", \"updated_at\": \"2026-05-22T11:04:44.496Z\", \"hypothesis\": \"MF5 Late-Layer-First baseline: synthetic importance scores (L0-9=1.0, L10-17=0.5, L18-27=0.001) → standard prune 20% → SFT → GRPO 100 steps → eval. Tests if CKA-only advantage is confounded by layer-depth bias. If depth-first ≈ CKA-only, the advantage is just removing deep layers, not CKA-guided selection.\", \"conclusion\": \"failed\"}, \"grpo_rasp_alpha3p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T08:48:06.001Z\", \"updated_at\": \"2026-05-22T10:39:07.034Z\", \"hypothesis\": \"α=3.0 GRPO 100 steps on checkpoint-935 (1 epoch SFT). Dose-response data point between α=2.0 and α=4.0. If monotonic: higher α → higher GSM8K accuracy, confirming CKA overlap suppression causally harms recovery.\", \"parent\": \"grpo_alpha4_20\", \"conclusion\": \"success\", \"notes\": \"GRPO 训练 100/100 steps 完成，但 checkpoint-100/model.safetensors 被截断（7.2GB vs 应有 11.5GB）。原因：westb 数据盘在保存时 100% 满。需要重跑 GRPO。SFT checkpoint-935 完好（11.5GB）。\"}, \"eval_gsm8k_sft_alpha2p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T10:19:50.623Z\", \"updated_at\": \"2026-05-22T10:22:56.503Z\", \"hypothesis\": \"α=2.0 SFT GSM8K eval for C1 decoupling. Paired with α=2.0 GRPO (66.11%). Critical: if SFT ~61-62%, Δ ≈ +4-5pp would break C1 universal ±2pp claim. Reviewer-flagged risk.\", \"parent\": \"pipeline_alpha2p0_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6497, \"gsm8k_correct\": 857, \"gsm8k_total\": 1319}}, \"eval_gsm8k_sft_alpha0p5_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T10:19:48.133Z\", \"updated_at\": \"2026-05-22T10:20:57.690Z\", \"hypothesis\": \"α=0.5 SFT GSM8K eval for C1 decoupling. Paired with α=0.5 GRPO (61.18%). Δ(GRPO-SFT) tests whether GRPO benefit is universal ±2pp across α values.\", \"parent\": \"pipeline_alpha0p5_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6073, \"gsm8k_correct\": 801, \"gsm8k_total\": 1319}}, \"grpo_qwen_math_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T08:50:34.293Z\", \"updated_at\": \"2026-05-22T09:54:05.974Z\", \"hypothesis\": \"MF3 cross-architecture validation: Qwen2.5-Math-7B CKA-only 20% pruned → SFT → GRPO 100 steps. Tests if CKA-guided pruning advantage transfers beyond DeepSeek-R1 to Qwen-Math family. P0 highest priority.\", \"parent\": \"sft_qwen_math_cka_only_20_v2\", \"conclusion\": \"success\"}, \"eval_gsm8k_grpo_alpha2p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T09:28:08.089Z\", \"updated_at\": \"2026-05-22T09:29:24.824Z\", \"hypothesis\": \"α=2.0 GRPO GSM8K eval. Dose-response data point: moderate overlap suppression (α=2.0) between α=1.0 (61.49%) and α=4.0 (62.77%). Tests monotonicity of dose-response curve.\", \"parent\": \"pipeline_alpha2p0_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6611, \"gsm8k_correct\": 872, \"gsm8k_total\": 1319}}, \"eval_gsm8k_grpo_alpha0p5_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T09:28:05.478Z\", \"updated_at\": \"2026-05-22T09:29:23.350Z\", \"hypothesis\": \"α=0.5 GRPO GSM8K eval. Dose-response data point: low overlap suppression (α=0.5) should yield lower accuracy than α=1.0 (61.49%) if CKA overlap suppression causally harms recovery.\", \"parent\": \"pipeline_alpha0p5_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6118, \"gsm8k_correct\": 807, \"gsm8k_total\": 1319}}, \"eval_math500_sft_standard_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T04:31:30.202Z\", \"updated_at\": \"2026-05-22T08:27:40.167Z\", \"hypothesis\": \"1.5B Standard 20% SFT MATH-500 @2048. Cross-scale comparison with CKA-only 1.5B (10.6%) to test if CKA-guided pruning advantage is scale-invariant.\", \"conclusion\": \"success\", \"metrics\": {\"math500_accuracy\": 0.054, \"correct\": 27, \"total\": 500, \"truncated\": 335}}, \"eval_math500_sft_rasp_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T04:31:31.934Z\", \"updated_at\": \"2026-05-22T08:06:21.924Z\", \"hypothesis\": \"1.5B RASP 20% SFT MATH-500 @2048. Cross-scale comparison: if ranking CKA-only > Standard > RASP holds at 1.5B, validates scale-invariant importance metric.\", \"metrics\": {\"math500_accuracy\": 0.062, \"correct\": 31, \"total\": 500}, \"conclusion\": \"negative\"}, \"eval_math500_sft_cka_only_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T02:30:44.919Z\", \"updated_at\": \"2026-05-22T08:06:20.289Z\", \"hypothesis\": \"Cross-scale (1.5B) CKA-only 20% SFT MATH-500 @2048 provides cross-scale generalization evidence. If CKA-guided pruning maintains relative advantage at 1.5B, it validates importance metric transfers across model sizes.\", \"conclusion\": \"negative\", \"metrics\": {\"math500_accuracy\": 0.106, \"correct\": 53, \"total\": 500}}, \"pipeline_alpha2p0_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T05:48:26.680Z\", \"updated_at\": \"2026-05-22T06:54:20.035Z\", \"hypothesis\": \"α=2.0 (moderate overlap suppression) between α=1.0 (54.43% GRPO) and α=4.0 (62.77%). Tests monotonicity of dose-response curve. If monotonic: CKA overlap suppression causally harms recovery. Includes SFT eval for C1 decoupling at this α.\", \"conclusion\": \"failed\", \"notes\": \"失败原因: EXIT_CODE=1, 日志末尾有 \\\"Terminated\\\"。SFT 训练仅到 step 15/5604 被外部终止。与 pipeline_alpha0p5_20 同时死亡——疑似共同外因。诊断 Worker worker_diagnose_pipeline_alpha_failures_20260522T065330 分析中。\"}, \"pipeline_alpha0p5_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T05:47:08.448Z\", \"updated_at\": \"2026-05-22T06:54:10.737Z\", \"hypothesis\": \"α=0.5 (minimal overlap suppression) should produce pruning similar to standard importance-only, predicting GSM8K accuracy near standard 20% (~59.84% GRPO). Combined with α=4.0 (62.77%) and α=1.0 (54.43%), establishes dose-response curve for overlap suppression strength.\", \"conclusion\": \"failed\", \"notes\": \"失败原因: EXIT_CODE=129 (SIGHUP), SFT 训练仅到 step 15/5604 被外部终止。日志无 Traceback/OOM。与 pipeline_alpha2p0_20 同时死亡——疑似共同外因。诊断 Worker worker_diagnose_pipeline_alpha_failures_20260522T065330 分析中。\"}, \"eval_gsm8k_sft_alpha4_20_v5\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T03:49:50.201Z\", \"updated_at\": \"2026-05-22T06:05:53.848Z\", \"hypothesis\": \"α=4.0 SFT GSM8K N=1319 full eval @2048. D100 critical for C1 decoupling universality. v4 lost to westd-29022 outage. Re-run on westd-32935.\", \"parent\": \"eval_gsm8k_sft_alpha4_20_v4\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6194, \"correct\": 817, \"total\": 1319, \"stderr\": 0.0134, \"eos_rate\": 0.981, \"avg_response_length\": 197.85}}, \"eval_gsm8k_grpo_alpha4_20_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T03:49:52.414Z\", \"updated_at\": \"2026-05-22T05:33:39.349Z\", \"hypothesis\": \"α=4.0 GRPO GSM8K N=1319 full eval @2048. v1 timed out at 774/1319 (62.93% interim). v2 ALLOCATED but westd-29022 died. Re-run on westd-32935 with --max_new_tokens 2048.\", \"parent\": \"eval_gsm8k_grpo_alpha4_20_v2\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6277, \"gsm8k_accuracy_ci\": 0.0133, \"gsm8k_correct\": 828, \"gsm8k_total\": 1319, \"eos_rate\": 0.9856, \"avg_response_length\": 188.16, \"natural_eos\": 1300, \"truncated\": 19}, \"notes\": \"Cron 误判为 failed（进程正常退出但 cron 未检测到 sentinel）。实际完成 1319/1319，accuracy=62.77%。α=4.0 GRPO > Standard GRPO (59.84%) > RASP α=1.0 GRPO (54.43%)。确认 α tuning 有效缓解 RASP collapse。checkpoint_path: /root/autodl-tmp/recovery_aware_struct_prune/grpo_alpha4_20/checkpoint-100, log_path: /root/recovery_aware_struct_prune/logs/eval_gsm8k_grpo_alpha4_20_v3.log, results_path: /root/recovery_aware_struct_prune/results/eval_gsm8k_grpo_alpha4_20_v3.json\"}, \"eval_math500_sft_cka_only_20_v7\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T00:40:59.108Z\", \"updated_at\": \"2026-05-22T04:25:20.089Z\", \"hypothesis\": \"CKA-only 20% SFT MATH-500 @2048 re-run on dedicated westb:0 GPU. v6 killed at 317/500 to split GPU workload. Expected ~29% based on prior @4096 results.\", \"parent\": \"eval_math500_sft_cka_only_20_v6\", \"conclusion\": \"negative\", \"metrics\": {\"math500_accuracy\": 0.268, \"correct\": 134, \"n_total\": 500, \"natural_eos\": 384, \"truncated\": 116, \"avg_response_length\": 673.278}}, \"eval_math500_sft_random_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-22T03:49:47.353Z\", \"updated_at\": \"2026-05-22T04:05:42.976Z\", \"hypothesis\": \"Random 20% SFT MATH-500 @2048. Re-run on westd-32935 after outage. Establishes SFT baseline for random pruning MATH-500.\", \"parent\": \"eval_math500_sft_random_20\", \"conclusion\": \"failed\", \"notes\": \"代码版本不一致导致崩溃，westd-32935 的 eval_math500.py 是旧版本（tqdm desc=\\\"MATH eval\\\" 而非 \\\"MATH-500 eval\\\"，normalize 函数不同）\"}, \"eval_math500_sft_standard_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T02:58:32.492Z\", \"updated_at\": \"2026-05-22T02:31:03.648Z\", \"notes\": \"v1 结果采用（v2 启动即崩溃）。结果文件: /root/autodl-tmp/recovery_aware_struct_prune/results/eval_math500_sft_standard_25.json。Director 于 2026-05-21 批准采用 v1 数据。\", \"hypothesis\": \"Standard 25% SFT model MATH-500 accuracy establishes pre-GRPO baseline for standard pruning at 25% sparsity, enabling SFT→GRPO recovery delta on MATH-500\", \"conclusion\": \"success\", \"metrics\": {\"math500_accuracy\": 0.14, \"correct\": 70, \"n_total\": 500, \"natural_eos\": 185, \"truncated\": 315, \"avg_response_length\": 1367.82, \"v1_accuracy\": 0.13, \"v1_correct\": 65}}, \"eval_math500_sft_cka_only_20_v6\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T19:45:37.307Z\", \"updated_at\": \"2026-05-22T00:38:58.182Z\", \"hypothesis\": \"CKA-only 20% SFT model MATH-500 @2048 accuracy re-run on westb:1 — v5 marked DONE but result may need validation; v6 ensures clean eval with consistent --max_new_tokens 2048 settings\", \"parent\": \"eval_math500_sft_cka_only_20_v5\", \"conclusion\": \"killed\"}, \"eval_gsm8k_grpo_alpha4_20_v2\": {\"status\": \"ALLOCATED\", \"created_at\": \"2026-05-21T21:42:15.836Z\", \"updated_at\": \"2026-05-22T00:36:33.520Z\", \"hypothesis\": \"α=4.0 GRPO maintains reward 0.15-0.26 (vs α=1.0 collapse to ~0.008), predicting GSM8K accuracy significantly above α=1.0 baseline. v1 timed out at 774/1319 showing 62.93% interim — full eval needed to confirm α-dependent collapse hypothesis.\", \"parent\": \"eval_gsm8k_grpo_alpha4_20\", \"notes\": \"Approved and QUEUED. Blocked: westd-29022 unreachable (port refused). Will submit immediately when server recovers. Config: nohup, --max_new_tokens 2048, timeout=8h, model=/root/autodl-tmp/recovery_aware_struct_prune/grpo_alpha4_20/checkpoint-100\"}, \"eval_math500_grpo_alpha4_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T19:27:35.287Z\", \"updated_at\": \"2026-05-22T00:23:12.454Z\", \"hypothesis\": \"α=4.0 GRPO MATH-500 @2048 accuracy for cross-benchmark validation of RASP collapse hypothesis.\", \"parent\": \"grpo_alpha4_20\", \"conclusion\": \"failed\", \"notes\": \"失败原因: westd-29022 服务器宕机，SSH 连接 5 次失败。基础设施故障，需服务器恢复后重新提交。\"}, \"eval_math500_sft_random_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T14:43:53.119Z\", \"updated_at\": \"2026-05-22T00:23:09.058Z\", \"hypothesis\": \"Random 20% SFT model MATH-500 @2048 accuracy establishes pre-GRPO baseline for random pruning, enabling SFT→GRPO recovery delta comparison with importance-based methods (CKA-only, Standard) at 20% sparsity on MATH-500\", \"parent\": \"eval_gsm8k_sft_random_20\", \"conclusion\": \"failed\", \"notes\": \"失败原因: westd-29022 服务器宕机，SSH 连接 5 次失败。基础设施故障，需服务器恢复后重新提交。\"}, \"eval_gsm8k_sft_alpha4_20_v4\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T22:35:22.241Z\", \"updated_at\": \"2026-05-22T00:23:07.474Z\", \"hypothesis\": \"If CKA-only GRPO provides ~0pp benefit over SFT (C1 decoupling), this should hold for α=4.0. SFT α=4.0 GSM8K baseline needed vs GRPO α=4.0 (interim 62.77%). v4 adds --max_new_tokens 2048 to prevent no-EOS stalls.\", \"parent\": \"sft_alpha4_20_v2\", \"conclusion\": \"failed\", \"notes\": \"失败原因: westd-29022 服务器宕机，SSH 连接 5 次失败 (Unable to connect to port 29022 on 36.103.198.204)。基础设施故障，非实验代码问题。需服务器恢复后重新提交。\"}, \"eval_math500_grpo_standard_20_fair_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T22:34:50.380Z\", \"updated_at\": \"2026-05-21T22:57:57.124Z\", \"hypothesis\": \"Standard GRPO 20% on MATH-500 @2048 to fill P0 data gap. Standard 25% GRPO scored 12.8% — expect 20% to score higher due to less aggressive pruning.\", \"parent\": \"grpo_standard_20_fair\", \"conclusion\": \"killed\"}, \"eval_gsm8k_sft_alpha4_20_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T22:30:33.451Z\", \"updated_at\": \"2026-05-21T22:33:56.550Z\", \"hypothesis\": \"If CKA-only GRPO provides ~0pp benefit over SFT (C1 decoupling), this pattern should hold for α=4.0 pruning as well. SFT α=4.0 GSM8K baseline needed to compare against GRPO α=4.0 (interim 62.77%) to test universality of decoupling.\", \"parent\": \"sft_alpha4_20_v2\", \"conclusion\": \"killed\"}, \"eval_gsm8k_sft_alpha4_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T21:41:39.959Z\", \"updated_at\": \"2026-05-21T22:30:18.285Z\", \"hypothesis\": \"If CKA-only GRPO provides ~0pp benefit over SFT (C1 decoupling), this pattern should hold for α=4.0 pruning as well. SFT α=4.0 GSM8K baseline is needed to compare against GRPO α=4.0 (interim 62.77%) to test universality of decoupling.\", \"parent\": \"sft_alpha4_20_v2\", \"conclusion\": \"failed\"}, \"eval_gsm8k_grpo_alpha4_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T19:27:31.038Z\", \"updated_at\": \"2026-05-21T21:43:12.907Z\", \"hypothesis\": \"α=4.0 GRPO GSM8K accuracy (N=1319). If comparable to CKA-only/Standard GRPO (~60-64%), proves α=4.0 avoids RASP collapse. If near-zero like α=1.0 RASP, confirms collapse is structural.\", \"parent\": \"grpo_alpha4_20\", \"conclusion\": \"failed\", \"metrics\": {\"accuracy_partial\": 0.6293, \"n_completed\": 774, \"n_total\": 1319, \"failure_reason\": \"timeout at 774/1319 — ~1.73% samples lack EOS token causing 5-6min stalls per sample, avg speed degraded from 2.5s to 9s/sample\"}}, \"eval_math500_sft_standard_25_2048\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-21T19:45:34.974Z\", \"updated_at\": \"2026-05-21T19:45:34.974Z\"}, \"eval_math500_sft_cka_only_20_v5\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T19:34:40.200Z\", \"updated_at\": \"2026-05-21T19:37:27.830Z\", \"hypothesis\": \"CKA-only 20% SFT model MATH-500 @2048 accuracy on westb — re-run to produce local results.json since v4_restart result only exists on westd\", \"parent\": \"eval_math500_sft_cka_only_20_v4_restart\", \"conclusion\": \"failed\", \"notes\": \"Process silently exited after 1/500 problems. Log has 10 lines, no error/traceback/OOM message. No results.json produced. Likely OOM kill or external termination on westb-23072 cuda:1.\"}, \"eval_math500_sft_cka_only_20\": {\"created_at\": \"2026-05-17T22:59:03.755Z\", \"hypothesis\": \"CKA-only 20% SFT model MATH-500 @2048 accuracy establishes pre-GRPO baseline for CKA-only pruning at 20% sparsity, enabling SFT→GRPO recovery delta analysis on MATH-500 alongside GSM8K results\", \"status\": \"DONE\", \"updated_at\": \"2026-05-21T19:34:21.955Z\", \"conclusion\": \"killed\", \"notes\": \"Intentionally killed per Director instruction: migrated from cuda:2 (shared, 4min/sample) to cuda:0 (dedicated) as eval_math500_sft_cka_only_20_v2. Progress at kill: 43/500.\", \"parent\": \"eval_math500_sft_cka_only_20_v4_restart\"}, \"grpo_alpha4_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T18:59:18.863Z\", \"updated_at\": \"2026-05-21T19:32:31.353Z\", \"hypothesis\": \"α=4.0 GRPO after SFT: if reward collapses (→0 like α=1.0 RASP GRPO), proves RASP collapse is structural, not hyperparameter-dependent. If reward stays positive and GSM8K improves over SFT, α tuning can mitigate collapse.\", \"parent\": \"sft_alpha4_20_v2\", \"metrics\": {\"final_reward\": 0.198, \"reward_range\": \"0.146-0.256\", \"steps\": 100, \"final_loss\": 0.018, \"final_kl\": 0.00198}, \"conclusion\": \"success\"}, \"sft_alpha4_20_v2\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-21T18:30:48.284Z\", \"updated_at\": \"2026-05-21T19:32:28.482Z\", \"hypothesis\": \"α=4.0 SFT recovery with save_only_model=True to prevent disk overflow. Pruning successful (19.09% sparsity). Testing if higher α mitigates RASP collapse after full SFT→GRPO→eval pipeline.\", \"parent\": \"sft_alpha4_20_manual\", \"conclusion\": \"success\", \"metrics\": {\"final_train_loss\": 0.8118, \"token_accuracy\": 0.8165, \"epochs\": 2, \"steps\": 936}}, \"eval_math500_sft_cka_only_15\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-21T19:29:26.608Z\", \"updated_at\": \"2026-05-21T19:29:53.809Z\", \"hypothesis\": \"CKA-only 15% SFT model MATH-500 @2048 accuracy establishes pre-GRPO baseline at 15% sparsity for cross-benchmark validation (complement GSM8K data), enabling cross-sparsity trend analysis on MATH-500\"}, \"pipeline_alpha4_0_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T18:01:07.962Z\", \"updated_at\": \"2026-05-21T18:29:56.477Z\", \"hypothesis\": \"α=4.0 has highest post-prune accuracy (40% GSM8K). If α=4.0 GRPO also collapses (reward→0 like α=1.0 RASP), it proves RASP collapse is a structural defect of the scoring method, not a hyperparameter issue. If GRPO recovers, α tuning can mitigate collapse. Retry after disk cleanup.\", \"parent\": \"pipeline_alpha4_0\", \"conclusion\": \"failed\"}, \"sft_alpha4_20_manual\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T18:06:16.677Z\", \"updated_at\": \"2026-05-21T18:25:39.695Z\", \"hypothesis\": \"Manual SFT step for α=4.0 pruned model (bypassing pipeline script). Pruning completed successfully (19.09% sparsity). SFT recovery on α=4.0 model to test if higher α mitigates RASP collapse.\", \"parent\": \"pipeline_alpha4_0_v2\", \"conclusion\": \"failed\"}, \"pipeline_alpha4_0\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T17:31:43.984Z\", \"updated_at\": \"2026-05-21T17:58:52.344Z\", \"hypothesis\": \"α=4.0 has highest post-prune accuracy (40% GSM8K). If α=4.0 GRPO also collapses (reward→0 like α=1.0 RASP), it proves RASP collapse is a structural defect of the scoring method, not a hyperparameter issue. If GRPO recovers, α tuning can mitigate collapse.\", \"conclusion\": \"failed\", \"notes\": \"磁盘满 (619G/619G) 导致 pruned model safetensors 写入失败。剪枝阶段成功 (actual sparsity 19.09%, 200 MLP groups pruned) 但保存到 /root/autodl-tmp/recovery_aware_struct_prune/pruned_alpha4_20 时 os error 28。需清理磁盘后以 pipeline_alpha4_0_v2 重跑。\"}, \"eval_math500_grpo_cka_only_25_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T13:54:50.310Z\", \"updated_at\": \"2026-05-21T17:33:50.709Z\", \"hypothesis\": \"CKA-only 25% GRPO model MATH-500 @2048 accuracy for cross-benchmark validation, re-run with correct max_new_tokens=2048 for consistency with 20% data\", \"parent\": \"eval_math500_grpo_cka_only_25\", \"conclusion\": \"success\", \"metrics\": {\"math500_accuracy\": 0.184, \"math500_stderr\": 0.0173, \"correct\": 92, \"n_total\": 500}}, \"eval_math500_sft_cka_only_25_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T13:54:51.945Z\", \"updated_at\": \"2026-05-21T17:29:14.940Z\", \"hypothesis\": \"CKA-only 25% SFT model MATH-500 @2048 accuracy establishes pre-GRPO baseline, re-run with correct max_new_tokens=2048 for consistency\", \"parent\": \"eval_math500_sft_cka_only_25\", \"conclusion\": \"success\", \"metrics\": {\"math500_accuracy\": 0.192, \"correct\": 96, \"n_total\": 500, \"std_err\": 0.0176}, \"notes\": \"Eval completed all 500 problems. Result JSON not saved due to IsADirectoryError (output_path pointed to directory instead of file). Metrics extracted from log.\"}, \"eval_gsm8k_sft_standard_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T08:13:12.112Z\", \"updated_at\": \"2026-05-21T14:40:37.092Z\", \"hypothesis\": \"Standard 25% SFT GSM8K accuracy establishes pre-GRPO floor for importance-based pruning at 25% sparsity, enabling SFT→GRPO recovery delta comparison with CKA-only 25%\", \"metrics\": {\"gsm8k_accuracy\": 0.5087, \"stderr\": 0.0138, \"correct\": 671, \"n_total\": 1319, \"eos_rate\": 0.953, \"avg_response_length\": 333.15}, \"conclusion\": \"success\"}, \"eval_math500_grpo_cka_only_20_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T12:47:44.429Z\", \"updated_at\": \"2026-05-21T14:03:27.746Z\", \"hypothesis\": \"CKA-only 20% GRPO model MATH-500 accuracy provides cross-benchmark validation at 20% sparsity and cross-method comparison with Random 20% GRPO MATH-500 (re-run with consistent eval settings)\", \"parent\": \"eval_math500_grpo_cka_only_20\", \"conclusion\": \"killed\"}, \"eval_math500_grpo_standard_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T11:42:06.222Z\", \"updated_at\": \"2026-05-21T14:03:25.448Z\", \"hypothesis\": \"Standard 25% GRPO model MATH-500 accuracy expected near-zero due to reward collapse (0.00813), providing strong evidence that standard pruning at 25% destroys RL recovery capacity\", \"parent\": \"eval_gsm8k_grpo_standard_25\", \"conclusion\": \"killed\"}, \"eval_math500_sft_cka_only_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T08:51:52.678Z\", \"updated_at\": \"2026-05-21T13:51:22.828Z\", \"hypothesis\": \"CKA-only 25% SFT model MATH-500 accuracy establishes pre-GRPO baseline for cross-benchmark validation, enabling SFT→GRPO recovery delta on MATH-500 at 25% sparsity\", \"conclusion\": \"killed\"}, \"eval_math500_grpo_cka_only_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T08:39:24.350Z\", \"updated_at\": \"2026-05-21T13:48:08.599Z\", \"hypothesis\": \"CKA-only 25% GRPO model MATH-500 accuracy provides cross-benchmark validation at 25% sparsity, complementing GSM8K results for the cross-sparsity table\", \"conclusion\": \"killed\"}, \"eval_math500_grpo_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T02:41:32.199Z\", \"updated_at\": \"2026-05-21T12:47:30.348Z\", \"hypothesis\": \"CKA-only 20% GRPO model MATH-500 accuracy provides cross-benchmark validation at 20% sparsity and cross-method comparison with Random 20% GRPO MATH-500\", \"parent\": \"grpo_cka_only_20\", \"metrics\": {\"accuracy\": 0.266, \"n_correct\": 133, \"n_total\": 500, \"stderr\": 0.0198, \"truncated\": 108, \"truncation_rate\": 0.216, \"avg_response_length\": 1124.24}, \"conclusion\": \"success\"}, \"eval_gsm8k_grpo_standard_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T06:42:08.819Z\", \"updated_at\": \"2026-05-21T12:37:17.579Z\", \"hypothesis\": \"Standard 25% GRPO后GSM8K评估。GRPO reward=0.00813 (near-total collapse)。验证 Standard pruning 在 25% 稀疏度下 GRPO 后数学推理能力。\", \"parent\": \"grpo_standard_25_westb\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.5186, \"stderr\": 0.0138, \"correct\": 684, \"n_total\": 1319, \"eos_rate\": 0.9575, \"avg_response_length\": 314.47}}, \"eval_math500_sft_standard_25_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T07:50:16.675Z\", \"updated_at\": \"2026-05-21T11:20:26.438Z\", \"hypothesis\": \"Standard 25% SFT model MATH-500 accuracy establishes pre-GRPO floor for standard pruning at 25% sparsity, complementing GSM8K evaluation for cross-benchmark consistency\", \"parent\": \"sft_standard_25\", \"conclusion\": \"failed\"}, \"eval_gsm8k_sft_cka_only_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T06:47:14.010Z\", \"updated_at\": \"2026-05-21T10:17:58.203Z\", \"hypothesis\": \"CKA-only 25% SFT model retains higher GSM8K accuracy than GRPO-recovered model's SFT baseline, establishing the pre-GRPO accuracy floor for measuring recovery delta at 25% sparsity\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6012, \"correct\": 793, \"n_total\": 1319, \"stderr\": 0.0135, \"eos_rate\": 0.9803, \"avg_response_length\": 243.6}}, \"eval_gsm8k_sft_random_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T06:47:16.459Z\", \"updated_at\": \"2026-05-21T08:47:06.620Z\", \"hypothesis\": \"Random 20% SFT model GSM8K accuracy establishes the pre-GRPO floor for random pruning, enabling SFT→GRPO recovery delta comparison across pruning methods at 20% sparsity\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.5125, \"correct\": 676, \"n_total\": 1319, \"stderr\": 0.0138, \"eos_rate\": 0.9932, \"avg_response_length\": 182.4}}, \"eval_gsm8k_grpo_cka_only_25_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T04:56:52.006Z\", \"updated_at\": \"2026-05-21T08:17:13.429Z\", \"hypothesis\": \"CKA-only 25% GRPO后GSM8K评估。model_path=/grpo_cka_only_25（根目录）。Cross-sparsity对比: Standard 25% GRPO=51.1%, RASP 25% GRPO=53.15%。\", \"parent\": \"grpo_cka_only_25\", \"notes\": \"正确 PID=322443 (v3提交)。323174 是重复提交已 kill。\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.5959, \"correct\": 786, \"n_total\": 1319, \"eos_rate\": 0.9818}}, \"grpo_standard_25_westb\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T03:00:00.000Z\", \"updated_at\": \"2026-05-21T06:40:00.000Z\", \"hypothesis\": \"Standard 25% GRPO v5 fair config (100 steps, lr=1e-6, beta=0.01, T=0.4, seed=42) on westb. Re-run with fair config for cross-method comparison.\", \"parent\": \"sft_standard_25\", \"conclusion\": \"success\", \"metrics\": {\"reward\": 0.00813, \"steps\": 100, \"collapse_pattern\": \"near_total_collapse\"}}, \"eval_gsm8k_grpo_random_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T04:56:53.980Z\", \"updated_at\": \"2026-05-21T06:38:00.000Z\", \"hypothesis\": \"Random 20% GRPO后GSM8K评估。Random pruning reward=0.189（最低），验证无结构保留的pruning在GRPO后数学推理能力。\", \"parent\": \"grpo_random_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.5057, \"gsm8k_stderr\": 0.0138, \"correct\": 667, \"total\": 1319, \"eos_rate\": 0.9954, \"avg_response_length\": 173}}, \"eval_gsm8k_grpo_random_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T04:47:26.216Z\", \"updated_at\": \"2026-05-21T04:52:00.000Z\", \"hypothesis\": \"Random 20% GRPO后GSM8K评估。Random pruning reward=0.189（最低），验证无结构保留的pruning在GRPO后数学推理能力。填补Table 2数据。\", \"parent\": \"grpo_random_20\", \"conclusion\": \"failed\", \"notes\": \"v2 已用 conda activate 重交\"}, \"eval_gsm8k_grpo_cka_only_25_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T04:03:53.404Z\", \"updated_at\": \"2026-05-21T04:47:35.353Z\", \"hypothesis\": \"CKA-only 25% GRPO后GSM8K评估（v2修正路径，Worker重交）。Cross-sparsity对比: Standard 25% GRPO=51.1%, RASP 25% GRPO=53.15%。验证CKA-guided pruning在25%稀疏度下的数学推理能力。\", \"parent\": \"grpo_cka_only_25\", \"notes\": \"原 PID 318738 因 /checkpoint-100 路径不存在崩溃。Worker 修正为 /grpo_cka_only_25 重交，新 PID=320735。\", \"conclusion\": \"failed\"}, \"sft_random_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T03:44:24.654Z\", \"updated_at\": \"2026-05-21T04:45:00.000Z\", \"hypothesis\": \"Random 20% pruning baseline SFT recovery. Random pruning 不保留任何结构信息，作为 ablation baseline 验证 CKA-guided pruning 的结构保留优势。\", \"conclusion\": \"success\", \"metrics\": {\"steps\": 1870, \"model_size_gb\": 12}}, \"grpo_random_20\": {\"created_at\": \"2026-05-17T13:30:31.016Z\", \"hypothesis\": \"Random pruning 的 GRPO collapse 行为 — 如果 collapse ≈ RASP (step~10)，则所有结构剪枝伤 RL；如果 ≈ Standard (step~60)，则 CKA-aware 选择特别伤 RL（redundancy-stability tradeoff 确认）；如果 stable（无 collapse），则 CKA narrative 需要重构。\", \"parent\": \"scoring_ablation_random_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-21T04:42:00.000Z\", \"conclusion\": \"success\", \"metrics\": {\"reward_mean\": 0.164, \"reward_range\": [0.14, 0.19], \"reward_peak\": 0.19, \"reward_peak_step\": 70, \"frac_zero_std_mean\": 0.333, \"frac_zero_std_range\": [0.3, 0.4], \"entropy_mean\": 0.221, \"entropy_range\": [0.2, 0.24], \"kl_mean\": 0.0045, \"steps_captured\": 9, \"max_step\": 90, \"pattern\": \"stable plateau, no collapse\", \"data_source\": \"log_file (W&B crashed before sync)\"}, \"notes\": \"Dynamics data from steps 10-90 sufficient for C2 gradient analysis. Timeout at step 97 (EXIT_CODE=124), no final checkpoint saved (save_steps=99999). W&B crashed before sync. Pattern confirmed: stable plateau, no collapse. Reclassified from failed. Note: no step 100 data, no checkpoint for downstream eval.\"}, \"eval_gsm8k_grpo_cka_only_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T03:40:26.264Z\", \"updated_at\": \"2026-05-21T04:04:21.554Z\", \"hypothesis\": \"CKA-only 25% GRPO后GSM8K评估。Cross-sparsity对比: Standard 25% GRPO=51.1%, RASP 25% GRPO=53.15%。验证CKA-guided pruning在25%稀疏度下的数学推理能力。\", \"parent\": \"grpo_cka_only_25\", \"conclusion\": \"failed\"}, \"grpo_cka_only_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T02:49:22.258Z\", \"updated_at\": \"2026-05-21T03:22:07.134Z\", \"hypothesis\": \"CKA-only 25% GRPO training (v5 fair config, 100 steps, lr=1e-6, beta=0.01, T=0.4, seed=42). Cross-sparsity comparison: Standard 25%=51.1%, RASP 25%=53.15%. Tests if CKA-guided pruning advantage holds at 25%.\", \"parent\": \"sft_cka_only_25\", \"notes\": \"W&B run: mirgxi5b. Cron 5x miss 误判 failed，实际正常完成。\", \"conclusion\": \"success\", \"metrics\": {\"reward\": 0.2875, \"steps\": 100}}, \"eval_humaneval_sft_standard_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T02:43:32.214Z\", \"updated_at\": \"2026-05-21T02:44:15.495Z\", \"hypothesis\": \"Standard 25% structured pruning + SFT recovery on HumanEval: measures code generation capability of the standard pruning baseline at 25% sparsity after SFT recovery.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.0183, \"stderr\": 0.0105, \"n_passed\": 3, \"n_total\": 164}}, \"sft_cka_only_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-21T01:50:42.758Z\", \"updated_at\": \"2026-05-21T02:40:00.000Z\", \"conclusion\": \"success\", \"hypothesis\": \"CKA-only 25% SFT recovery training. 2 epochs on pruned model (5.81B params, 23.67% actual sparsity). Prepares for GRPO → eval pipeline.\", \"metrics\": {\"final_loss\": 0.6508, \"mean_token_accuracy\": 0.8285, \"training_time_s\": 1644}}, \"prune_cka_only_25\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T13:43:54.266Z\", \"updated_at\": \"2026-05-21T01:50:00.000Z\", \"conclusion\": \"success\", \"hypothesis\": \"CKA-only pruning at 25% sparsity. Generates pruned model for SFT→GRPO→eval pipeline to complete cross-sparsity comparison (15%/20%/25%).\", \"metrics\": {\"actual_sparsity\": 0.2367, \"mlp_groups_pruned\": 248, \"mlp_groups_total\": 784, \"attn_groups_pruned\": 0, \"attn_groups_total\": 112, \"param_count_B\": 5.81, \"original_param_count_B\": 7.62}, \"notes\": \"[2026-05-21] 重跑成功。2026-05-18 首次尝试失败（PREPARING 状态卡住）。今天用 worker 重新执行 pruning，CPU 运行约 5 min 完成。α 默认值（未显式设置），calibration 样本数使用脚本默认。\"}, \"eval_gsm8k_grpo_standard_15_seed123_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T23:00:14.007Z\", \"updated_at\": \"2026-05-21T00:57:58.499Z\", \"hypothesis\": \"GSM8K N=1319 eval on Standard 15% GRPO seed123 (v3 checkpoint on data disk). Fixed: HF_HOME pointing to data disk cache, removed HF_DATASETS_OFFLINE.\", \"parent\": \"grpo_standard_15_seed123_v3\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.6513, \"accuracy_se\": 0.0131, \"n_correct\": 859, \"n_total\": 1319, \"eos_rate\": 0.9932, \"avg_response_length\": 183.25}}, \"eval_gsm8k_grpo_standard_15_seed456_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T23:00:15.387Z\", \"updated_at\": \"2026-05-21T00:51:20.262Z\", \"hypothesis\": \"GSM8K N=1319 eval on Standard 15% GRPO seed456 (v3 checkpoint on data disk). Fixed: tokenizer.json copied from seed123, HF_HOME pointing to data disk cache.\", \"parent\": \"grpo_standard_15_seed456_v3\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6543, \"gsm8k_stderr\": 0.0131, \"n_correct\": 863, \"n_total\": 1319, \"eos_rate\": 0.9939, \"avg_response_length\": 180.23}}, \"eval_gsm8k_grpo_cka_only_15_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T21:35:28.222Z\", \"updated_at\": \"2026-05-21T00:18:00.000Z\", \"hypothesis\": \"GSM8K N=1319 eval on CKA-only 15% GRPO seed123. Multi-seed validation for 15% sparsity gap statistical significance.\", \"parent\": \"grpo_cka_only_15_seed123\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 73.09, \"n_correct\": 964, \"n_total\": 1319, \"stderr\": 1.22, \"eos_rate\": 98.79, \"truncated\": 16}, \"notes\": \"GSM8K accuracy 73.09% (964/1319). Cron 曾误判 failed 后由 Director 恢复 RUNNING，最终正常完成。\"}, \"eval_gsm8k_grpo_cka_only_15_seed456\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T21:35:29.444Z\", \"updated_at\": \"2026-05-21T00:06:17.294Z\", \"hypothesis\": \"GSM8K N=1319 eval on CKA-only 15% GRPO seed456. Multi-seed validation for 15% sparsity gap statistical significance.\", \"parent\": \"grpo_cka_only_15_seed456\", \"notes\": \"[2026-05-20T23:15] Director 确认进程仍在运行 (PID 285821, cuda:1, 824/1319, 98% GPU利用率)。Cron 5x miss 误判为 failed，已恢复 RUNNING。\", \"metrics\": {\"accuracy\": 0.721, \"n_correct\": 951, \"n_total\": 1319, \"stderr\": 0.0123, \"eos_rate\": 0.9894, \"avg_response_length\": 201.94}, \"conclusion\": \"success\"}, \"eval_gsm8k_grpo_standard_15_seed456_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T22:51:43.300Z\", \"updated_at\": \"2026-05-20T22:55:03.785Z\", \"hypothesis\": \"GSM8K N=1319 eval on Standard 15% GRPO seed456 (v3 checkpoint on data disk). Multi-seed validation for 15% sparsity Standard method significance testing.\", \"parent\": \"grpo_standard_15_seed456_v3\", \"conclusion\": \"failed\"}, \"eval_gsm8k_grpo_standard_15_seed123_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T22:51:40.540Z\", \"updated_at\": \"2026-05-20T22:55:02.249Z\", \"hypothesis\": \"GSM8K N=1319 eval on Standard 15% GRPO seed123 (v3 checkpoint on data disk). Multi-seed validation for 15% sparsity Standard method significance testing.\", \"parent\": \"grpo_standard_15_seed123_v3\", \"conclusion\": \"failed\"}, \"grpo_standard_15_seed456_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T21:58:14.439Z\", \"updated_at\": \"2026-05-20T22:51:31.775Z\", \"hypothesis\": \"Retry of grpo_standard_15_seed456 (v1 disk full, v2 wrong model path). Same v5 fair config (100 steps, beta=0.01, temperature=0.4, lr=1e-6, dapo loss, format_reward=0.1). Fixed: absolute model path + HF_HUB_OFFLINE=1. 88G free disk.\", \"conclusion\": \"success\"}, \"grpo_standard_15_seed123_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T21:58:11.697Z\", \"updated_at\": \"2026-05-20T22:51:30.499Z\", \"hypothesis\": \"Retry of grpo_standard_15_seed123 (v1 disk full, v2 wrong model path). Same v5 fair config (100 steps, beta=0.01, temperature=0.4, lr=1e-6, dapo loss, format_reward=0.1). Fixed: absolute model path + HF_HUB_OFFLINE=1. 88G free disk.\", \"conclusion\": \"success\"}, \"grpo_standard_15_seed456_v4\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T22:48:48.683Z\", \"updated_at\": \"2026-05-20T22:51:29.186Z\", \"hypothesis\": \"Retry #4 of Standard 15% seed456 GRPO. v1=disk full, v2=wrong model path, v3=checkpoint saved to root partition then moved by cleanup. v4: absolute output_dir on data disk (/root/autodl-tmp/), absolute model_path, HF_HUB_OFFLINE=1. v5 fair config (100 steps, beta=0.01, temperature=0.4, lr=1e-6, dapo, format_reward=0.1).\", \"conclusion\": \"killed\"}, \"grpo_standard_15_seed123_v4\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T22:48:45.710Z\", \"updated_at\": \"2026-05-20T22:51:27.850Z\", \"hypothesis\": \"Retry #4 of Standard 15% seed123 GRPO. v1=disk full, v2=wrong model path, v3=checkpoint saved to root partition then moved by cleanup. v4: absolute output_dir on data disk (/root/autodl-tmp/), absolute model_path, HF_HUB_OFFLINE=1. v5 fair config (100 steps, beta=0.01, temperature=0.4, lr=1e-6, dapo, format_reward=0.1).\", \"conclusion\": \"killed\"}, \"eval_gsm8k_grpo_standard_15_seed456\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T22:46:01.814Z\", \"updated_at\": \"2026-05-20T22:48:41.050Z\", \"hypothesis\": \"GSM8K N=1319 eval on Standard 15% GRPO seed456 (v3 checkpoint). Multi-seed validation for 15% sparsity Standard method significance testing.\", \"parent\": \"grpo_standard_15_seed456_v3\", \"conclusion\": \"failed\"}, \"eval_gsm8k_grpo_standard_15_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T22:45:58.919Z\", \"updated_at\": \"2026-05-20T22:48:39.764Z\", \"hypothesis\": \"GSM8K N=1319 eval on Standard 15% GRPO seed123 (v3 checkpoint). Multi-seed validation for 15% sparsity Standard method significance testing.\", \"parent\": \"grpo_standard_15_seed123_v3\", \"conclusion\": \"failed\"}, \"grpo_standard_15_seed456_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T21:54:20.980Z\", \"updated_at\": \"2026-05-20T21:58:01.768Z\", \"hypothesis\": \"Retry of grpo_standard_15_seed456 (failed: SafetensorError no space left on device). Same v5 fair config (100 steps, beta=0.01, temperature=0.4, lr=1e-6, dapo loss, format_reward=0.1). Disk cleaned to 88G free before retry.\", \"parent\": \"grpo_standard_15_seed456\", \"conclusion\": \"failed\"}, \"grpo_standard_15_seed123_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T21:54:17.512Z\", \"updated_at\": \"2026-05-20T21:58:00.479Z\", \"hypothesis\": \"Retry of grpo_standard_15_seed123 (failed: SafetensorError no space left on device). Same v5 fair config (100 steps, beta=0.01, temperature=0.4, lr=1e-6, dapo loss, format_reward=0.1). Disk cleaned to 88G free before retry.\", \"parent\": \"grpo_standard_15_seed123\", \"conclusion\": \"failed\"}, \"grpo_standard_15_seed456\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T20:55:02.947Z\", \"updated_at\": \"2026-05-20T21:35:21.067Z\", \"hypothesis\": \"Multi-seed validation (seed=456) of Standard 15% GRPO training. v5 fair config (100 steps). Seed=42 (grpo_standard_15_v2): completed with reward=0.1375. Third seed for Standard 15% cross-sparsity significance testing.\", \"conclusion\": \"failed\"}, \"grpo_standard_15_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T20:55:00.121Z\", \"updated_at\": \"2026-05-20T21:35:18.771Z\", \"hypothesis\": \"Multi-seed validation (seed=123) of Standard 15% GRPO training. v5 fair config (100 steps). Seed=42 (grpo_standard_15_v2): completed with reward=0.1375. Second seed for Standard 15% cross-sparsity significance testing.\", \"conclusion\": \"failed\"}, \"grpo_cka_only_15_seed456\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T20:54:57.409Z\", \"updated_at\": \"2026-05-20T21:35:16.671Z\", \"hypothesis\": \"Multi-seed validation (seed=456) of CKA-only 15% GRPO training. v5 fair config (100 steps). Seed=42 (grpo_cka_only_15_v2): completed with reward=0.4019. Third seed point for CKA-only 15% recovery consistency and statistical significance.\", \"conclusion\": \"success\"}, \"grpo_cka_only_15_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T20:54:54.710Z\", \"updated_at\": \"2026-05-20T21:35:14.509Z\", \"hypothesis\": \"Multi-seed validation (seed=123) of CKA-only 15% GRPO training. v5 fair config (100 steps). Seed=42 (grpo_cka_only_15_v2): completed with reward=0.4019. Second seed point to establish CKA-only 15% recovery consistency for cross-sparsity significance testing.\", \"conclusion\": \"success\"}, \"eval_gsm8k_sft_standard_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T17:07:58.760Z\", \"updated_at\": \"2026-05-20T19:58:14.139Z\", \"hypothesis\": \"GSM8K N=1319 eval on Standard 20% SFT checkpoint (pre-GRPO). Direct measurement of SFT baseline for Standard 20% — needed for paper Table 2 exact GRPO delta calculation.\", \"parent\": \"pipeline_standard_20\", \"metrics\": {\"gsm8k_accuracy\": 0.5921, \"stderr\": 0.0135, \"correct\": 781, \"total\": 1319, \"eos_rate\": 0.9848, \"avg_response_length\": 206.68}, \"conclusion\": \"success\"}, \"eval_gsm8k_dense_unpruned\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T16:28:28.020Z\", \"updated_at\": \"2026-05-20T19:36:49.374Z\", \"hypothesis\": \"GSM8K N=1319 eval on dense unpruned DeepSeek-R1-Distill-Qwen-7B. Ceiling reference for paper — all pruned models should be compared against this baseline to show accuracy retention rate.\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.9083, \"gsm8k_accuracy_ci\": 0.0079, \"correct\": 1198, \"total\": 1319, \"eos_rate\": 0.9871, \"avg_response_length\": 594, \"truncated\": 17, \"eval_time\": \"3h7m\"}}, \"eval_gsm8k_sft_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T16:32:21.874Z\", \"updated_at\": \"2026-05-20T18:49:11.554Z\", \"hypothesis\": \"GSM8K N=1319 eval on CKA-only 20% SFT checkpoint (pre-GRPO). Direct measurement of SFT baseline for 20% sparsity — needed for paper table to calculate exact GRPO delta. Current estimate ~63.91% from reverse calculation.\", \"parent\": \"pipeline_cka_only_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6391, \"gsm8k_accuracy_ci\": 0.0132, \"correct\": 843, \"total\": 1319, \"eos_rate\": 0.9901, \"avg_response_length\": 198.1, \"truncated\": 13}}, \"eval_gsm8k_sft_cka_only_15\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T15:19:42.152Z\", \"updated_at\": \"2026-05-20T18:33:53.213Z\", \"hypothesis\": \"GSM8K N=1319 eval on CKA-only 15% SFT checkpoint (pre-GRPO). Fills cross-sparsity comparison table: CKA-only 15% SFT baseline. Compare with Standard 15% SFT (eval_gsm8k_sft_standard_15) to quantify pruning method effect at SFT stage for 15% sparsity.\", \"parent\": \"pipeline_cka_only_15\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.7218, \"correct\": 952, \"total\": 1319}}, \"eval_gsm8k_sft_rasp_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T17:09:04.809Z\", \"updated_at\": \"2026-05-20T18:10:54.576Z\", \"hypothesis\": \"GSM8K N=1319 eval on RASP 20% SFT checkpoint (pre-GRPO). Fills Table 2 SFT column for RASP method. Compare with CKA-only and Standard SFT baselines at same sparsity.\", \"parent\": \"pipeline_rasp_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6149, \"gsm8k_accuracy_ci\": 0.0134, \"correct\": 811, \"total\": 1319, \"eos_rate\": 0.9826, \"avg_response_length\": 216.5}}, \"eval_gsm8k_grpo_standard_15_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T14:43:21.408Z\", \"updated_at\": \"2026-05-20T16:28:25.206Z\", \"hypothesis\": \"GSM8K N=1319 full eval on Standard 15% GRPO v2 (reward=0.1375). W-C6 cross-sparsity: compare with CKA-only 15% GRPO (interim 74.22%). If Standard 15% << CKA-only 15%, confirms recovery gradient holds at lower sparsity.\", \"parent\": \"grpo_standard_15_v2\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6611, \"correct\": 872, \"total\": 1319, \"eos_rate\": 0.993, \"avg_response_length\": 184}}, \"eval_gsm8k_sft_standard_15\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T14:23:49.568Z\", \"updated_at\": \"2026-05-20T16:28:23.020Z\", \"hypothesis\": \"GSM8K N=1319 eval on Standard 15% SFT checkpoint (pre-GRPO). Establishes SFT baseline accuracy for Standard 15% sparsity. Paired with eval_gsm8k_grpo_standard_15_v2 to measure GRPO recovery delta. Compare with SFT CKA-only 15% to quantify pruning method effect at SFT stage.\", \"parent\": \"pipeline_standard_15\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6649, \"correct\": 877, \"total\": 1319, \"eos_rate\": 0.993, \"avg_response_length\": 183}}, \"eval_gsm8k_grpo_cka_only_15_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T13:32:17.474Z\", \"updated_at\": \"2026-05-20T16:04:05.569Z\", \"hypothesis\": \"GSM8K N=1319 full eval on CKA-only 15% GRPO v2. Training complete: loss=0.2027, reward=0.4019. W-C6 cross-sparsity: if 15% CKA-only > 15% Standard (pending), confirms recovery gradient holds at lower sparsity. Compare with 20% CKA-only (64.37% seed42).\", \"parent\": \"grpo_cka_only_15_v2\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.7309, \"gsm8k_accuracy_ci\": 0.0122, \"correct\": 964, \"total\": 1319, \"eos_rate\": 0.9894, \"avg_response_length\": 202.4}}, \"eval_gsm8k_grpo_cka_only_20_seed456_full\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T13:31:33.529Z\", \"updated_at\": \"2026-05-20T16:04:03.508Z\", \"hypothesis\": \"GSM8K N=1319 full eval on CKA-only GRPO seed=456. Training complete: loss=0.0999, reward=0.2925. Seed=42: 64.37%, seed=123: 64.22%. If seed=456 matches, confirms CKA-only GRPO recovery is consistent across seeds (3-seed parity with Standard). P0 W-C4.\", \"parent\": \"grpo_cka_only_20_seed456\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.6459, \"gsm8k_accuracy_ci\": 0.0132, \"correct\": 852, \"total\": 1319, \"eos_rate\": 0.9886, \"avg_response_length\": 204.3}}, \"eval_gsm8k_sft_qwen_standard_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T10:32:12.883Z\", \"updated_at\": \"2026-05-20T15:44:54.102Z\", \"hypothesis\": \"GSM8K N=200 eval of Qwen2.5-Math-7B Standard 20% SFT epoch 1 (checkpoint-935). Post-prune accuracy was 18.5%. Standard uses importance-based pruning. Fair comparison with CKA-only at same training point (epoch 1.0, step 935).\", \"parent\": \"sft_qwen_math_standard_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.21, \"correct\": 42, \"total\": 200}}, \"eval_gsm8k_sft_qwen_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T10:32:11.084Z\", \"updated_at\": \"2026-05-20T15:39:07.657Z\", \"hypothesis\": \"GSM8K N=200 eval of Qwen2.5-Math-7B CKA-only 20% SFT epoch 1 (checkpoint-935). Post-prune accuracy was 1.00% (near zero). CKA-only preserves layer diversity but causes severe initial damage. Fair comparison with Standard at same training point (epoch 1.0, step 935). If CKA-only SFT recovers above Standard, validates recovery-aware principle on Qwen-Math.\", \"parent\": \"sft_qwen_math_cka_only_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 0.515, \"gsm8k_accuracy_ci\": 0.0353, \"correct\": 103, \"total\": 200, \"eos_rate\": 0.27, \"avg_response_length\": 1536, \"truncated\": 146, \"eval_time\": \"4h00m04s\"}}, \"grpo_standard_15_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T13:42:06.715Z\", \"updated_at\": \"2026-05-20T14:23:39.083Z\", \"hypothesis\": \"Standard 15% GRPO training (100 steps, v5 config). W-C6 cross-sparsity pair with grpo_cka_only_15_v2 (reward=0.4019). If Standard 15% < CKA-only 15%, confirms recovery gradient holds at lower sparsity.\", \"parent\": \"pipeline_standard_15\", \"conclusion\": \"success\", \"metrics\": {\"loss\": 0.01142, \"reward\": 0.1375, \"reward_std\": 0.2778, \"kl\": 0.004099, \"entropy\": 0.1932, \"grad_norm\": 3.547, \"total_steps\": 100, \"training_time\": \"21m49s\"}}, \"eval_gsm8k_grpo_standard_20_seed123_full\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T10:27:04.283Z\", \"updated_at\": \"2026-05-20T13:38:49.241Z\", \"hypothesis\": \"GSM8K N=1319 full eval on Standard GRPO seed=123. N=200 quick eval showed 64.00% (128/200). Seed=42 full eval: 59.44% (784/1319). Full eval to determine if seed123's higher accuracy holds or is small-sample noise (N=200 95% CI ≈ ±6.7pp).\", \"parent\": \"grpo_standard_20_seed123\", \"metrics\": {\"accuracy\": 0.5989, \"n_correct\": 790, \"n_total\": 1319, \"stderr\": 0.0135, \"eos_rate\": null}, \"conclusion\": \"success\"}, \"eval_gsm8k_grpo_standard_20_seed456_full\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T10:27:05.741Z\", \"updated_at\": \"2026-05-20T13:38:47.186Z\", \"hypothesis\": \"GSM8K N=1319 full eval on Standard GRPO seed=456. N=200 quick eval showed 66.50% (133/200), exceeding CKA-only's 64.37%. Seed=42 full eval: 59.44% (784/1319). Full eval to determine if seed456's high accuracy holds or is small-sample noise (N=200 95% CI ≈ ±6.5pp).\", \"parent\": \"grpo_standard_20_seed456\", \"metrics\": {\"accuracy\": 0.602, \"n_correct\": 794, \"n_total\": 1319, \"stderr\": 0.01348, \"eos_rate\": 0.9856}, \"conclusion\": \"success\"}, \"grpo_cka_only_15_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T11:58:03.218Z\", \"updated_at\": \"2026-05-20T13:35:06.015Z\", \"hypothesis\": \"CKA-only 15% GRPO restart (resume from checkpoint-20). Original pipeline_cka_only_15 failed at checkpoint-20 due to disk full. Now disk has 185G available. W-C6 cross-sparsity validation: if CKA-only > Standard holds at 15%, strengthens the claim.\", \"parent\": \"pipeline_cka_only_15\", \"notes\": \"checkpoint-20 from original pipeline_cka_only_15 is corrupted (safetensors incomplete metadata, disk-full damage). Starting fresh from sft_cka_only_15. New output_dir: grpo_cka_only_15_v2. Director requested --save_only_model but script doesn't support it.\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.2027, \"avg_train_loss\": 0.11, \"final_reward\": 0.4019, \"final_kl\": 0.0018, \"train_steps\": 100, \"train_runtime_min\": 22.5}}, \"grpo_cka_only_20_seed456\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T11:36:13.866Z\", \"updated_at\": \"2026-05-20T13:35:02.652Z\", \"hypothesis\": \"Multi-seed validation (seed=456) of CKA-only 20% GRPO training. v5 fair config (100 steps, beta=0.01, loss_type=dapo, temperature=0.4). Seed=42: 64.37%, seed=123: 64.22%. Third seed point to establish CKA-only method's recovery consistency and enable 3-seed parity comparison with Standard (3 seeds: 59.44%, pending, pending). P0 审稿硬需求 W-C4.\", \"parent\": \"grpo_cka_only_20\", \"notes\": \"Director requested --save_only_model but script doesn't support it. Training started at step 0, ~12.7s/step, ETA ~21min for 100 steps. tmux session: grpo_seed456.\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.0999, \"avg_train_loss\": 0.0881, \"final_reward\": 0.2925, \"final_kl\": 0.0017, \"train_steps\": 100, \"train_runtime_min\": 21.8}}, \"prune_eval_standard_30\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T04:08:24.071Z\", \"updated_at\": \"2026-05-20T11:56:25.682Z\", \"hypothesis\": \"Standard importance pruning at 30% sparsity post-prune GSM8K accuracy. Extends sparsity ladder (20%→25%→30%) to probe Standard degradation curve. No SFT/GRPO recovery, raw post-prune performance.\", \"notes\": \"Original run killed (PID 191519). Re-submitted in tmux eval_std30, PID 202006 on GPU cuda:1. Diagnostic confirms model on cuda:0 (CUDA_VISIBLE_DEVICES=1), 86% util. Speed ~30-48s/sample = ~15-17h ETA for N=1319.\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 2.8, \"note\": \"N=500 partial result (killed by Director, 30% sparsity = complete collapse, N=500 precision sufficient)\", \"n_evaluated\": 500, \"n_total\": 1319, \"eos_rate\": 1.2, \"avg_len\": 4057}}, \"prune_eval_cka_only_30\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T04:08:22.614Z\", \"updated_at\": \"2026-05-20T11:56:24.517Z\", \"hypothesis\": \"CKA-only pruning at 30% sparsity post-prune GSM8K accuracy. Extends sparsity ladder (20%→25%→30%) to probe CKA-only degradation curve. No SFT/GRPO recovery, raw post-prune performance.\", \"notes\": \"Original run killed (PID 191446). Re-submitted in tmux eval_cka30, PID 201928 on GPU cuda:0. Diagnostic confirms model on cuda:0, 85% util, 11.5GB VRAM. Speed ~48s/sample = ~17h ETA for N=1319. Original run was likely also on GPU (identical speed pattern).\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 1.6, \"note\": \"N=500 partial result (killed by Director, 30% sparsity = complete collapse, N=500 precision sufficient)\", \"n_evaluated\": 500, \"n_total\": 1319, \"eos_rate\": 5.6, \"avg_len\": 4009}}, \"sft_qwen_math_standard_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T09:18:20.201Z\", \"updated_at\": \"2026-05-20T10:31:09.608Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% SFT recovery epoch 2 (resume from checkpoint-935 = epoch 1 完成). 原始 sft_qwen_math_standard_20 在 935/1870 steps 崩溃（磁盘满）。checkpoint-935 验证完好（339 tensors）。从 epoch 1 权重续跑 1 epoch。\", \"parent\": \"sft_qwen_math_standard_20\", \"conclusion\": \"failed\"}, \"sft_qwen_math_cka_only_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T09:18:17.089Z\", \"updated_at\": \"2026-05-20T09:50:15.333Z\", \"hypothesis\": \"Qwen2.5-Math-7B CKA-only 20% SFT recovery epoch 2 (resume from checkpoint-935 = epoch 1 完成). 原始 sft_qwen_math_cka_only_20 训练完成 1870 steps 但最终 checkpoint 保存失败（磁盘满）。checkpoint-935 验证完好（339 tensors）。从 epoch 1 权重续跑 1 epoch。\", \"parent\": \"sft_qwen_math_cka_only_20\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.3481, \"mean_token_accuracy\": 0.8595, \"train_runtime_sec\": 1013, \"train_samples_per_second\": 7.38, \"epochs\": 1}}, \"eval_gsm8k_grpo_standard_20_seed456\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T09:15:10.283Z\", \"updated_at\": \"2026-05-20T09:49:10.630Z\", \"hypothesis\": \"GSM8K N=200 quick eval on Standard GRPO seed=456 model. Seed=42 accuracy: 59.44% (N=1319), seed=123 being evaluated. If seed=456 within ±5pp of seed=42, confirms Standard recovery capacity is not seed-dependent.\", \"parent\": \"grpo_standard_20_seed456\", \"metrics\": {\"accuracy\": 0.665, \"n_correct\": 133, \"n_total\": 200, \"stderr\": 0.0334, \"eos_rate\": 0.995, \"avg_response_length\": 166.9}, \"conclusion\": \"success\"}, \"eval_gsm8k_grpo_standard_20_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T09:15:16.595Z\", \"updated_at\": \"2026-05-20T09:49:08.654Z\", \"hypothesis\": \"GSM8K N=200 quick eval on Standard GRPO seed=123 model. Seed=42 accuracy: 59.44% (N=1319). If seed=123 within ±5pp of seed=42, confirms Standard stagnation pattern produces consistent accuracy across seeds.\", \"parent\": \"grpo_standard_20_seed123\", \"metrics\": {\"accuracy\": 0.64, \"n_correct\": 128, \"n_total\": 200, \"stderr\": 0.0339, \"eos_rate\": 0.99, \"avg_response_length\": 187.9}, \"conclusion\": \"success\"}, \"sft_qwen_math_standard_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T06:37:03.101Z\", \"updated_at\": \"2026-05-20T09:22:57.378Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% pruned model (post-prune accuracy 18.5%) can recover to ~50-60% GSM8K accuracy via SFT, following the same recovery pattern observed in DeepSeek-R1. This validates cross-architecture generalizability of the pruning method.\", \"parent\": \"qwen_math_7b_feasibility\", \"conclusion\": \"failed\"}, \"qwen_math_7b_feasibility\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T04:26:29.226Z\", \"updated_at\": \"2026-05-20T09:22:48.543Z\", \"hypothesis\": \"RASP pruning pipeline designed for DeepSeek-R1-Distill-Qwen-7B transfers to Qwen2.5-Math-7B with zero code changes because both use identical Qwen2ForCausalLM architecture (28 layers, 28 heads, 4 KV heads, hidden=3584, intermediate=18944), validating cross-model generalizability of the method.\", \"conclusion\": \"failed\"}, \"grpo_standard_20_seed456\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T06:22:10.493Z\", \"updated_at\": \"2026-05-20T09:13:48.616Z\", \"hypothesis\": \"Multi-seed validation (seed=456) of Standard 20% GRPO. v5 fair config (100 steps, beta=0.01, loss_type=dapo, temperature=0.4). Seed=42 baseline: 59.44% GSM8K. Third seed point to establish Standard method's recovery variance.\", \"parent\": \"grpo_stage2_standard_20_fair\", \"metrics\": {\"steps_completed\": 100, \"runtime_sec\": 2745, \"peak_reward\": 0.0844, \"peak_reward_step\": 90, \"final_reward\": 0.06, \"final_frac_zero_std\": 0.65, \"seed\": 456, \"wandb_run\": \"wg0iv4oi\", \"wandb_mode\": \"offline\"}, \"conclusion\": \"success\"}, \"grpo_standard_20_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T06:22:27.444Z\", \"updated_at\": \"2026-05-20T09:13:45.445Z\", \"hypothesis\": \"Multi-seed validation (seed=123) of Standard 20% GRPO. v5 fair config (100 steps, beta=0.01, loss_type=dapo, temperature=0.4, max_completion_length=1024). Seed=42 baseline: 59.44% GSM8K (784/1319). If seed=123 result within ±3pp, confirms Standard method's recovery capacity is stable across seeds.\", \"parent\": \"grpo_stage2_standard_20_fair\", \"metrics\": {\"steps_completed\": 100, \"runtime_sec\": 2783, \"peak_reward\": 0.0619, \"peak_reward_step\": 80, \"final_reward\": 0.0594, \"final_frac_zero_std\": 0.6, \"seed\": 123, \"wandb_run\": \"pgzwv725\", \"wandb_mode\": \"offline\"}, \"conclusion\": \"success\"}, \"sft_qwen_math_cka_only_20\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-20T06:37:00.532Z\", \"updated_at\": \"2026-05-20T06:41:34.165Z\", \"hypothesis\": \"Qwen2.5-Math-7B CKA-only 20% pruned model SFT recovery. Post-prune accuracy 1.00% (2/200, near zero). CKA-only removes most redundant structures, causing severe initial damage. SFT recovery should be significant if model capacity is preserved. Tests whether CKA-only's 'remove redundancy, preserve capacity' principle transfers to Qwen-Math.\", \"parent\": \"qwen_math_7b_feasibility\"}, \"pipeline_cka_only_15\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T04:09:53.762Z\", \"updated_at\": \"2026-05-20T06:18:30.603Z\", \"hypothesis\": \"CKA-only pruning at 15% sparsity full pipeline (prune→SFT→GRPO 100 steps→GSM8K eval N=1319). Lower sparsity should yield higher recovery than 20%. CKA-only preserves layer diversity, predicting stronger GRPO recovery vs Standard at same sparsity.\", \"notes\": \"SFT complete: train_loss=0.6309, final_loss=0.4918, mean_token_accuracy=0.8698, runtime=1741s. Model saved to /root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_15/\", \"metrics\": {\"failure_detail\": \"SafetensorError: No space left on device. checkpoint-20 intact (3.7GB). Can restart GRPO from checkpoint-20.\", \"checkpoint_10_status\": \"deleted_in_cleanup\", \"checkpoint_20_status\": \"intact_3.7GB\"}, \"conclusion\": \"failed\"}, \"pipeline_standard_15\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T04:09:55.898Z\", \"updated_at\": \"2026-05-20T06:18:28.590Z\", \"hypothesis\": \"Standard pruning at 15% sparsity full pipeline (prune→SFT→GRPO 100 steps→GSM8K eval N=1319). Baseline comparison for CKA-only at same sparsity. Standard pruning uses magnitude-only importance, expected to show lower GRPO recovery than CKA-only.\", \"notes\": \"SFT complete: train_loss=0.668, final_loss=0.5363, mean_token_accuracy=0.8561, runtime=1733s. Model saved to /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_15/\", \"metrics\": {\"failure_detail\": \"SafetensorError: No space left on device. checkpoint-20 corrupted (model.safetensors only 40KB). Cannot restart from checkpoint, needs full re-run from SFT.\", \"checkpoint_10_status\": \"deleted_in_cleanup\", \"checkpoint_20_status\": \"corrupted_40bytes\"}, \"conclusion\": \"failed\"}, \"eval_mbpp_grpo_standard_20_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T21:00:40.293Z\", \"updated_at\": \"2026-05-20T03:06:43.359Z\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.131, \"correct\": 49, \"total\": 374, \"stderr\": 0.0174}}, \"eval_humaneval_sft_standard_20_1p5b_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T11:35:45.876Z\", \"updated_at\": \"2026-05-20T03:06:22.483Z\", \"hypothesis\": \"1.5B SFT Standard HumanEval pass@1 @2048 on westb. Cross-scale validation of capability breadth claim. Running on westb cuda:0 where checkpoints already exist (no scp needed).\", \"metrics\": {\"pass_at_1\": 0.0061, \"correct\": 1, \"total\": 164, \"stderr\": 0.0061}, \"conclusion\": \"success\"}, \"eval_humaneval_sft_standard_20_2048_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T10:05:36.497Z\", \"updated_at\": \"2026-05-20T03:06:20.863Z\", \"hypothesis\": \"SFT Standard 20% HumanEval pass@1 @2048. Uses current sft_standard_20 model on westd-29022 (same model as MATH-500 eval at 25.8%). Fills SFT×method HumanEval matrix. Compare with GRPO Standard fair (~10% interim) and SFT CKA-only (~24% interim).\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1341, \"correct\": 22, \"total\": 164, \"stderr\": 0.0266}}, \"eval_humaneval_sft_cka_only_20_1p5b_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T11:32:47.965Z\", \"updated_at\": \"2026-05-20T03:06:19.658Z\", \"hypothesis\": \"1.5B SFT CKA-only HumanEval pass@1 @2048. Cross-scale validation of capability breadth claim. 7B SFT CKA-only result: failed (pass@1=0). Testing whether 1.5B scale shows different pattern, as SFT alone may not activate code generation capability regardless of pruning criterion.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.0061, \"correct\": 1, \"total\": 164, \"stderr\": 0.0061}}, \"eval_humaneval_grpo_cka_only_20_1p5b_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T11:32:50.649Z\", \"updated_at\": \"2026-05-20T03:06:18.579Z\", \"hypothesis\": \"1.5B GRPO CKA-only HumanEval pass@1 @2048. Cross-scale validation of capability breadth claim. 7B result: pass@1=20.12%. If 1.5B CKA-only also shows strong code generation after GRPO (>> Standard/RASP), strengthens cross-scale evidence that CKA-based pruning preserves broader capability spectrum.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0, \"correct\": 0, \"total\": 164, \"stderr\": 0}}, \"rci_formalization_plan036\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-20T02:53:37.317Z\", \"updated_at\": \"2026-05-20T02:53:37.317Z\", \"hypothesis\": \"RCI 形式化：CKA diversity score (1 - mean diagonal CKA) 与 GRPO recovery capacity 的 rank correlation。如果 ρ > 0.9，CKA diversity 可 zero-cost 预测 RL recovery。E3 heatmap 数据 + registry recovery metrics。Plan_036, C2 mechanism。\"}, \"eval_gsm8k_grpo_standard_20_step50\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T02:46:11.922Z\", \"updated_at\": \"2026-05-20T02:48:55.688Z\", \"hypothesis\": \"GSM8K N=1319 eval on Standard GRPO step-50 checkpoint. paper_framing 引用 58.91% 但无结果 JSON 可追溯。重跑以建立完整 provenance。用 grpo_stage2_standard_20_fair/checkpoint-50。预期 ~58.91%。C1 decoupling 证据：SFT 59.29% vs GRPO-50 ~58.91% = Δ≈0.38pp。\", \"parent\": \"grpo_standard_20_fair\", \"conclusion\": \"killed\", \"notes\": \"失败原因: EXIT_CODE=1 — 模型路径 /root/autodl-tmp/recovery_aware_struct_prune/grpo_stage2_standard_20_fair/checkpoint-50 不存在。Transformers 尝试当 HF repo id 解析报 OSError。已知失败模式（同 eval_mbpp_sft_rasp_20）。已派 Worker 查找正确路径。\"}, \"eval_mbpp_sft_shortgpt_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T22:23:35.431Z\", \"updated_at\": \"2026-05-20T02:43:15.577Z\", \"hypothesis\": \"Retry of eval_mbpp_sft_shortgpt_20 which failed with EXIT_CODE=127 (command not found — missing conda activation). ShortGPT SFT 20% MBPP pass@1 @2048. ShortGPT GSM8K SFT=44.73%, GRPO=43.37%. Depth pruning 在 MBPP 上预期显著差于 fine-grained methods (CKA-only SFT 12.83%, RASP SFT 11.76%). 验证 coarse layer removal 对代码生成的破坏性。关联 ShortGPT baseline comparison。\", \"parent\": \"eval_mbpp_sft_shortgpt_20\", \"metrics\": {\"pass_at_1\": 0.1043, \"stderr\": 0.0158, \"n_correct\": 39, \"n_total\": 374, \"avg_response_length\": 1166.4, \"median_response_length\": 773.5}, \"conclusion\": \"success\"}, \"eval_mbpp_grpo_shortgpt_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T22:33:19.363Z\", \"updated_at\": \"2026-05-20T02:43:06.318Z\", \"hypothesis\": \"Retry of eval_mbpp_grpo_shortgpt_20 which failed with EXIT_CODE=127 (missing conda activation). GRPO ShortGPT 20% MBPP pass@1 @2048. ShortGPT GSM8K: SFT=44.73%, GRPO=43.37% (GRPO退化). Depth pruning 在 MBPP 上预期显著差于 fine-grained methods。与 eval_mbpp_sft_shortgpt_20_v2 配对，完成 ShortGPT MBPP SFT/GRPO 对比。关联 ShortGPT baseline。\", \"parent\": \"grpo_shortgpt_20\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1444, \"stderr\": 0.0182, \"n_correct\": 54, \"n_total\": 374, \"avg_response_length\": 1140.8, \"median_response_length\": 804.5}}, \"eval_mbpp_sft_standard_20_v4\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T22:26:22.996Z\", \"updated_at\": \"2026-05-20T02:16:04.699Z\", \"hypothesis\": \"MBPP pass@1 eval on SFT Standard 20% @2048. Dense baseline=53.48%. 此为手动 tmux 提交的 orphan 进程补录。目前 85/374 (23%), interim pass@1=0.175。HF_DATASETS_OFFLINE=1。关联 C2。\", \"parent\": \"eval_mbpp_sft_standard_20_clean\", \"metrics\": {\"pass_at_1\": 0.1203, \"stderr\": 0.0168, \"n_correct\": 45, \"n_total\": 374, \"avg_response_length\": 1084.1, \"median_response_length\": 746.5}, \"conclusion\": \"success\"}, \"eval_mbpp_grpo_standard_20_v4\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T21:01:23.058Z\", \"updated_at\": \"2026-05-20T01:46:54.906Z\", \"hypothesis\": \"GRPO Standard 20% pruned model should achieve ~13% pass@1 on MBPP, consistent with prior v1 partial results at 335/374 tasks\", \"parent\": \"eval_mbpp_grpo_standard_20_v3\", \"metrics\": {\"pass_at_1\": 0.131, \"n_correct\": 49, \"n_total\": 374, \"stderr\": 0.01745, \"avg_response_length\": 1058.7, \"median_response_length\": 726}, \"conclusion\": \"success\"}, \"eval_mbpp_grpo_shortgpt_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T22:28:09.552Z\", \"updated_at\": \"2026-05-19T22:33:14.612Z\", \"hypothesis\": \"MBPP pass@1 eval on GRPO ShortGPT 20% @2048. ShortGPT GSM8K: SFT=44.73%, GRPO=43.37% (GRPO退化). Depth pruning 在 MBPP 上预期同样差于 fine-grained methods。与 eval_mbpp_sft_shortgpt_20 配对，完成 ShortGPT MBPP SFT/GRPO 对比。关联 ShortGPT baseline。\", \"parent\": \"grpo_shortgpt_20\", \"conclusion\": \"failed\", \"notes\": \"失败原因: EXIT_CODE=127 — 命令缺少 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base，导致 python 不在 PATH。与 eval_mbpp_sft_shortgpt_20 同因。已创建 eval_mbpp_grpo_shortgpt_20_v2 修复重跑。\"}, \"eval_mbpp_sft_cka_only_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T18:37:10.228Z\", \"updated_at\": \"2026-05-19T22:25:23.041Z\", \"hypothesis\": \"MBPP pass@1 for 1.5B SFT CKA-only 20% model @2048. Dense 7B baseline=53.48%. 1.5B cross-scale validation: if 1.5B SFT CKA-only shows higher MBPP pass@1 than 1.5B SFT Standard/RASP, confirms recovery gradient generalizes across model scales on code benchmark.\", \"metrics\": {\"pass_at_1\": 0, \"pass_at_1_stderr\": 0, \"n_correct\": 0, \"n_total\": 374}, \"conclusion\": \"negative\"}, \"eval_mbpp_sft_shortgpt_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T21:55:30.750Z\", \"updated_at\": \"2026-05-19T22:23:36.554Z\", \"hypothesis\": \"ShortGPT SFT 20% MBPP pass@1 @2048. ShortGPT GSM8K SFT=44.73%, GRPO=43.37% (GRPO退化). Depth pruning (整层移除) 在 MBPP 上预期也显著差于 fine-grained methods (CKA-only SFT 12.83%, RASP SFT 11.76%). 验证 coarse layer removal 对代码生成的破坏性。关联 ShortGPT baseline comparison。\", \"conclusion\": \"failed\", \"notes\": \"失败原因: EXIT_CODE=127 — 命令缺少 source /root/miniconda3/bin/activate，导致 python 不在 PATH。已创建 eval_mbpp_sft_shortgpt_20_v2 修复重跑。\"}, \"eval_mbpp_sft_standard_20_clean\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T21:20:59.505Z\", \"updated_at\": \"2026-05-19T22:22:10.288Z\", \"hypothesis\": \"MBPP pass@1 eval on SFT Standard 20% @2048. Dense baseline=53.48%. 前4次被杀（exit code 143/124/129），排查确认为 submit_training_job 的 timeout wrapper 和 SIGHUP。清理 exit 文件后用全新 session 名 mbpp_sft_std_clean 重跑，绕过旧 session 名匹配。预期 ~12.8%。关联 C2。\", \"parent\": \"eval_mbpp_sft_standard_20_v3\", \"conclusion\": \"failed\"}, \"cka_scoring_stability_ablation\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T21:21:10.933Z\", \"updated_at\": \"2026-05-19T22:21:53.770Z\", \"hypothesis\": \"CKA scoring stability across calibration sizes (256/512/1024). If Spearman ρ > 0.95 between all pairs, CKA scoring is robust to calibration size — directly answers reviewer concern about scoring sensitivity. Plan_014, C2 mechanism evidence.\", \"metrics\": {\"spearman_256v512_attn\": 0.989, \"spearman_256v512_mlp\": 0.9683, \"spearman_256v512_combined\": 0.9788, \"spearman_256v1024_attn\": 0.9762, \"spearman_256v1024_mlp\": 0.9464, \"spearman_256v1024_combined\": 0.9641, \"spearman_512v1024_attn\": 0.995, \"spearman_512v1024_mlp\": 0.9908, \"spearman_512v1024_combined\": 0.9938, \"min_combined_rho\": 0.964, \"mean_combined_rho\": 0.979, \"stable\": true}, \"conclusion\": \"success\"}, \"eval_mbpp_grpo_rasp_20_v2\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-19T21:55:33.867Z\", \"updated_at\": \"2026-05-19T21:57:27.088Z\", \"notes\": \"取消：eval_mbpp_grpo_rasp_20 已实际完成 (pass@1=13.1%, 49/374)，v2 不需要。\"}, \"eval_mbpp_sft_standard_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T18:56:15.766Z\", \"updated_at\": \"2026-05-19T21:57:06.135Z\", \"hypothesis\": \"1.5B SFT Standard 20% MBPP pass@1 @2048. 与 westb:1 同时跑的 1.5B SFT CKA-only MBPP 对比，验证 recovery gradient 在 1.5B scale 上的 MBPP 表现。预期 CKA-only > Standard，与 7B GSM8K 跨 scale 一致。关联 C2。\", \"parent\": \"eval_mbpp_sft_standard_20\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.008021, \"n_correct\": 3, \"n_total\": 374, \"stderr\": 0.004613, \"avg_response_length\": 1658.6, \"median_response_length\": 2048}}, \"eval_mbpp_grpo_rasp_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T18:18:35.729Z\", \"updated_at\": \"2026-05-19T21:55:32.779Z\", \"hypothesis\": \"MBPP pass@1 eval on GRPO RASP 20% model @2048. Dense baseline=53.48% (200/374). RASP GRPO GSM8K=60.88%, HumanEval=10.37%. Tests RASP GRPO code generation on MBPP. Completes MBPP 3×2 matrix. Expected: between CKA-only GRPO (14.17%) and Standard GRPO (running). Recovery gradient on MBPP validates C2 capability breadth claim on second code benchmark.\", \"notes\": \"第3次失败: EXIT_CODE=129 (SIGHUP) 进程在加载 MBPP 数据集时被终止。模型加载成功。与 eval_mbpp_sft_standard_20 (SIGTERM 143)、eval_mbpp_grpo_standard_20 (timeout 124) 同一模式——submit_training_job 框架的信号管理导致。需要手动 tmux + HF_DATASETS_OFFLINE=1 绕过。将创建 v2 重试。\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.131, \"n_correct\": 49, \"n_total\": 374, \"stderr\": 0.0174}}, \"eval_mbpp_sft_standard_20_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T20:56:27.627Z\", \"updated_at\": \"2026-05-19T21:21:06.212Z\", \"hypothesis\": \"MBPP pass@1 eval on SFT Standard 20% model @2048. Dense baseline=53.48% (200/374). 前两次被外部 SIGTERM 杀死 (189/374)。手动 tmux 无 timeout wrapper 重跑。预期 pass@1 ~12.8% (基于前次 180/374 checkpoint)。关联 C2 capability breadth。\", \"conclusion\": \"failed\", \"notes\": \"进程被 SIGTERM (exit code 143) 杀死。排查发现无活跃 watchdog/cron，杀因是 submit_training_job 框架的 timeout wrapper。已清理 exit 文件，用新 session 名重跑 (eval_mbpp_sft_standard_20_clean)。\"}, \"eval_mbpp_sft_rasp_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T18:18:34.640Z\", \"updated_at\": \"2026-05-19T21:08:00.610Z\", \"hypothesis\": \"SFT RASP 20% model retains more MBPP code generation capability than CKA-only pruning due to recovery-aware pruning preserving structurally important parameters\", \"notes\": \"Model not found on westb. 7B SFT RASP checkpoint is on westd (sft_rasp_20_westd), not westb. Need to rerun on westd when GPU available.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1176, \"stderr\": 0.0167, \"n_correct\": 44, \"n_total\": 374, \"dense_baseline_pass_at_1\": 0.5348, \"degradation_pct\": 78.01, \"avg_response_length\": 810.7, \"median_response_length\": 247}}, \"eval_mbpp_sft_standard_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T18:05:01.037Z\", \"updated_at\": \"2026-05-19T20:28:39.279Z\", \"hypothesis\": \"MBPP pass@1 eval on SFT Standard 20% model @2048. Dense baseline=53.48% (200/374). Standard SFT GSM8K=63.84%, HumanEval=13.41%. If MBPP SFT Standard shows lower code capability than SFT CKA-only (running), confirms CKA-only preserves broader capabilities even before GRPO. Part of MBPP matrix for C2 capability breadth claim.\", \"notes\": \"GPU field correction: registry shows cuda:1 but actual running GPU is cuda:0 (CUDA_VISIBLE_DEVICES=0 in command maps to physical cuda:1 via framework injection).\", \"conclusion\": \"failed\"}, \"eval_mbpp_grpo_standard_20_v2\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-19T20:25:10.598Z\", \"updated_at\": \"2026-05-19T20:25:20.782Z\", \"hypothesis\": \"Retry of eval_mbpp_grpo_standard_20 which timed out at 335/374 (89.6%). Same setup: Standard GRPO 20% MBPP pass@1 @2048. Dense baseline=53.48%. Partial result: pass@1≈0.1313 at 320 samples. Increased timeout_hours=6 to ensure completion.\", \"parent\": \"eval_mbpp_grpo_standard_20\"}, \"eval_mbpp_grpo_standard_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T16:20:40.387Z\", \"updated_at\": \"2026-05-19T20:24:35.666Z\", \"hypothesis\": \"Standard GRPO 20% MBPP pass@1 @2048. Dense baseline=53.48%. Compare with CKA-only GRPO MBPP (running). Standard GRPO GSM8K=59.44% vs CKA-only 64.37% — if capability breadth claim holds, Standard should show larger degradation on code generation (MBPP) than math (GSM8K).\", \"conclusion\": \"failed\", \"notes\": \"失败原因: EXIT_CODE=124 超时 (4h limit, 完成 335/374=89.6%) | 已有成果: partial pass@1≈0.1313 at 320/374 (42 correct) | 建议: 重提交 timeout_hours=6, 同命令同 GPU\"}, \"eval_mbpp_sft_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T17:20:00.596Z\", \"updated_at\": \"2026-05-19T19:58:30.970Z\", \"hypothesis\": \"MBPP pass@1 eval on SFT CKA-only 20% model. Dense baseline=53.48% (200/374). CKA-only preserves most code generation capability after pruning. Compare SFT vs GRPO on MBPP to test redistribution hypothesis on second code benchmark.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1283, \"stderr\": 0.0173, \"n_correct\": 48, \"n_total\": 374, \"dense_baseline_pass_at_1\": 0.5348, \"degradation_pct\": 76.01, \"avg_response_length\": 643.8, \"median_response_length\": 363.5}}, \"eval_humaneval_sft_rasp_20_1p5b_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T11:35:50.597Z\", \"updated_at\": \"2026-05-19T18:52:30.545Z\", \"hypothesis\": \"1.5B SFT RASP HumanEval pass@1 @2048. Cross-scale validation. 7B GRPO RASP: 10.98%. RASP pruning expected between Standard and CKA-only on code generation at 1.5B scale.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0, \"n_correct\": 0, \"n_total\": 164, \"note\": \"1.5B SFT RASP, all truncated at 2048 tokens\"}}, \"eval_humaneval_grpo_rasp_20_1p5b_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T11:35:52.444Z\", \"updated_at\": \"2026-05-19T18:36:01.960Z\", \"hypothesis\": \"1.5B GRPO RASP HumanEval pass@1 @2048. Cross-scale validation. 7B result: pass@1=10.98%. If 1.5B RASP shows intermediate code capability (between Standard and CKA-only) after GRPO, confirms RASP partially preserves capability breadth across scales.\", \"conclusion\": \"killed\", \"notes\": \"Director cancelled: 1.5B HumanEval has no discriminative power (all methods 0-1%). GPU reassigned to 1.5B MBPP eval which has better cross-scale validation potential.\"}, \"eval_mbpp_grpo_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:41:07.213Z\", \"updated_at\": \"2026-05-19T18:17:54.178Z\", \"hypothesis\": \"MBPP pass@1 eval on GRPO CKA-only 20% model @2048. Dense baseline=53.48% (200/374). CKA-only GRPO showed strongest recovery on GSM8K (64.37%) and HumanEval (20.12%). If MBPP follows same pattern (CKA-only > Standard > RASP), confirms capability breadth claim (C2) generalizes to second code benchmark. Compare with parallel eval_mbpp_grpo_standard_20 and eval_mbpp_sft_cka_only_20.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1417, \"n_correct\": 53, \"n_total\": 374, \"stderr\": 0.018}}, \"eval_gsm8k_grpo_shortgpt_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T17:19:18.419Z\", \"updated_at\": \"2026-05-19T18:17:53.164Z\", \"hypothesis\": \"GSM8K eval on ShortGPT GRPO checkpoint-100. ShortGPT SFT=44.73%, if GRPO improves significantly it suggests depth-pruned models can still benefit from RL. If minimal improvement or collapse, confirms coarse layer removal limits GRPO recovery capacity vs fine-grained methods (CKA-only 64.37%, Standard 59.44%).\", \"parent\": \"grpo_shortgpt_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 43.37, \"n_correct\": 572, \"n_total\": 1319, \"stderr\": 0.0136}}, \"eval_gsm8k_sft_shortgpt_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T15:47:16.122Z\", \"updated_at\": \"2026-05-19T18:03:15.831Z\", \"hypothesis\": \"ShortGPT SFT checkpoint GSM8K eval. After depth pruning (5/28 layers removed by Block Influence scoring) + SFT warmup (loss=0.62, token_accuracy=0.83), measure GSM8K accuracy. Compare with fine-grained pruning SFT results: CKA-only SFT ~60%, Standard SFT ~64%. ShortGPT expected lower due to coarse layer removal destroying more representations.\", \"parent\": \"sft_shortgpt_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 44.73, \"n_correct\": 590, \"n_total\": 1319}}, \"grpo_shortgpt_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T16:04:46.243Z\", \"updated_at\": \"2026-05-19T18:02:50.896Z\", \"hypothesis\": \"GRPO recovery on ShortGPT depth-pruned model (5/28 layers removed by BI scoring, 15.3% sparsity). After SFT warmup (loss=0.62). Tests whether coarse layer removal (ShortGPT) leads to lower GRPO recovery than fine-grained structural pruning (CKA-only 64.37%, Standard 59.44%, RASP 60.88%). Expected to show collapse or severe stagnation because removing entire layers destroys more distributed representations needed for RL training.\", \"parent\": \"sft_shortgpt_20\", \"conclusion\": \"failed\", \"notes\": \"checkpoint-100 model intact, can be used for eval. Crash was torch serialization error, not model corruption.\"}, \"sft_shortgpt_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:22:26.084Z\", \"updated_at\": \"2026-05-19T18:02:48.590Z\", \"hypothesis\": \"ShortGPT depth pruning (20%, 5/28 layers removed) after SFT warmup will show lower recovery capacity than fine-grained structural pruning methods (Standard/CKA-only/RASP) because coarse layer removal destroys more distributed representations needed for GRPO recovery. Layers removed: [15,16,17,24,25], actual param sparsity 15.30%.\", \"conclusion\": \"success\"}, \"eval_gsm8k_grpo_cka_only_20_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T17:47:34.008Z\", \"updated_at\": \"2026-05-19T17:48:24.627Z\", \"hypothesis\": \"GSM8K eval on GRPO CKA-only 20% seed123 checkpoint. Tests reproducibility of CKA-only GRPO GSM8K performance (original seed42 = 64.37%). If seed123 matches closely, confirms CKA-only GRPO advantage is robust across seeds.\", \"parent\": \"grpo_cka_only_20_seed123\", \"metrics\": {\"accuracy\": 0.6422, \"stderr\": 0.0132, \"n_correct\": 847, \"n_total\": 1319, \"eos_rate\": 0.9909, \"avg_response_length\": 195.97, \"natural_eos\": 1307, \"truncated\": 12}, \"conclusion\": \"success\"}, \"eval_humaneval_grpo_standard_20_1p5b_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T11:35:48.029Z\", \"updated_at\": \"2026-05-19T17:02:50.370Z\", \"hypothesis\": \"1.5B GRPO Standard HumanEval pass@1 @2048. Cross-scale validation baseline. 7B GRPO Standard HumanEval failed (multiple attempts). If 1.5B Standard also shows weak code generation after GRPO (vs CKA-only), strengthens claim that standard pruning loses broader capabilities.\", \"conclusion\": \"success\"}, \"gradient_flow_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T15:03:16.535Z\", \"updated_at\": \"2026-05-19T16:38:41.269Z\", \"hypothesis\": \"CKA-only pruned models exhibit significantly stronger gradient signals (per-layer L2 norm) compared to Standard and RASP, with statistical significance (Wilcoxon p<0.05). This gradient magnitude difference is consistent with CKA-only's superior GRPO recovery capacity.\", \"conclusion\": \"success\", \"metrics\": {\"cka_only_mean_grad_norm\": 0.3229, \"standard_mean_grad_norm\": 0.1118, \"rasp_mean_grad_norm\": 0.1431, \"cka_vs_standard_ratio\": 2.89, \"rasp_vs_standard_ratio\": 1.28, \"cka_vs_standard_significant_layers\": \"55/56\", \"cka_vs_rasp_significant_layers\": \"56/56\", \"rasp_vs_standard_significant_layers\": \"45/56\", \"rasp_vs_standard_nonsig_layers\": \"layer_18_mlp,layer_19_attn,layer_19_mlp,layer_20_attn,layer_20_mlp,layer_21_attn,layer_21_mlp,layer_22_attn,layer_24_mlp,layer_27_attn,layer_27_mlp\", \"n_samples\": 200, \"statistical_test\": \"Wilcoxon signed-rank, per-layer\", \"bootstrap_n\": 1000, \"seed\": 42}}, \"eval_gsm8k_grpo_rasp_20_fair\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T12:47:37.399Z\", \"updated_at\": \"2026-05-19T16:17:16.053Z\", \"hypothesis\": \"GRPO RASP 20% fair (v5 config) GSM8K 全量评估。RASP 结合 recovery-awareness 与 structural pruning，预期性能介于 Standard (59.44%) 和 CKA-only (64.37%) 之间。若 RASP ≈ Standard，说明 recovery-awareness 的增益主要来自 CKA 信号而非 RASP 的混合策略。N=1319。\", \"parent\": \"eval_gsm8k_grpo_standard_20_fair_v2\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.6088, \"stderr\": 0.0134, \"n_correct\": 803, \"n_total\": 1319, \"eos_rate\": 0.9879, \"avg_response_length\": 195.7}, \"notes\": \"Cron false positive: eval脚本不走W&B误判failed。实际 accuracy=60.88% (803/1319)。RASP 介于 Standard (59.44%) 和 CKA-only (64.37%) 之间，更靠近 Standard。RASP-Standard gap=1.44pp, CKA-RASP gap=3.49pp。recovery-awareness 增益主要来自 CKA 信号。\"}, \"eval_mbpp_dense_unpruned\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T13:47:53.814Z\", \"updated_at\": \"2026-05-19T16:17:00.452Z\", \"hypothesis\": \"Dense unpruned DeepSeek-R1-Distill-Qwen-7B MBPP pass@1 baseline @2048. Establishes ceiling performance for MBPP code generation. All pruned models' MBPP results will be compared against this baseline.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.5348, \"stderr\": 0.0258, \"n_correct\": 200, \"n_total\": 374}, \"notes\": \"Cron false positive: eval脚本不走W&B，进程正常退出后cron检测不到指标误判failed。实际 pass@1=53.48% (200/374), stderr=0.0258。Dense baseline for MBPP.\"}, \"eval_humaneval_sft_rasp_20_2048_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T13:18:20.664Z\", \"updated_at\": \"2026-05-19T15:47:14.846Z\", \"hypothesis\": \"SFT RASP 20% HumanEval pass@1 @2048. Fills RASP SFT cell in HumanEval matrix. GRPO RASP = 10.98%. If SFT RASP ≈ GRPO RASP, confirms redistribution-not-expansion pattern holds for RASP too. Compare with CKA-only SFT=GRPO=20.12%.\", \"parent\": \"eval_humaneval_sft_rasp_20_2048\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1037, \"stderr\": 0.0238, \"n_correct\": 17, \"n_total\": 164, \"avg_response_length\": 1253.7, \"median_response_length\": 2048}}, \"grpo_cka_only_20_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T09:27:11.294Z\", \"updated_at\": \"2026-05-19T15:21:17.415Z\", \"hypothesis\": \"Multi-seed validation (seed=123) of CKA-only 20% GRPO training. If CKA-only advantage holds across seeds, strengthens C1 claim that pruning criteria determine recovery capacity. Seed 42 result: 64.37% GSM8K.\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.1361, \"final_step_loss\": 0.05054, \"final_reward\": 0.2975, \"final_reward_std\": 0.4097, \"train_steps\": 100, \"train_runtime_hours\": 11.63, \"wandb_run\": \"j8kn0sqd\"}}, \"gradient_flow_analysis\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:44:25.606Z\", \"updated_at\": \"2026-05-19T14:45:13.584Z\", \"hypothesis\": \"CKA-only pruned models exhibit stronger gradient flow (higher per-layer gradient norms) compared to Standard pruned models, enabling more effective GRPO recovery. Standard pruning creates weaker gradient signals that limit training effectiveness.\", \"conclusion\": \"success\", \"metrics\": {\"cka_only_attn_grad_mean\": 0.3135, \"cka_only_attn_grad_cv\": 1.2231, \"cka_only_mlp_grad_mean\": 0.285, \"cka_only_mlp_grad_cv\": 1.2424, \"standard_attn_grad_mean\": 0.1316, \"standard_attn_grad_cv\": 1.1363, \"standard_mlp_grad_mean\": 0.1222, \"standard_mlp_grad_cv\": 1.1489, \"grad_magnitude_ratio_attn\": 2.38, \"grad_magnitude_ratio_mlp\": 2.33}}, \"cka_calibration_stability_ablation\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:21:15.548Z\", \"updated_at\": \"2026-05-19T14:32:43.647Z\", \"hypothesis\": \"CKA-based functional overlap scores F(h) are stable across calibration sizes (256/512/1024 samples), with Spearman rho > 0.95 between any two sizes. This validates that our pruning criterion is not sensitive to calibration hyperparameter.\", \"conclusion\": \"success\", \"metrics\": {\"split_half_rho\": 0.9932, \"n_splits\": 5, \"size_sensitivity_128\": 0.982, \"size_sensitivity_256\": 0.989, \"size_sensitivity_512\": 0.995}}, \"eval_humaneval_grpo_standard_20_fair_2048_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T07:05:14.343Z\", \"updated_at\": \"2026-05-19T14:20:25.129Z\", \"hypothesis\": \"GRPO stage2 with standard 20% fair pruning recovers meaningful code generation ability on HumanEval, demonstrating that the fair pruning strategy preserves code-critical layers better than CKA-only pruning.\", \"notes\": \"2026-05-19 19:06 progress check: 156/164 (95.1%), interim pass@1 ~0.1143 at problem 140. ~15min remaining.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1098, \"n_correct\": 18, \"n_total\": 164}}, \"eval_humaneval_sft_standard_20_2048_v4\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:01:09.628Z\", \"updated_at\": \"2026-05-19T14:12:28.675Z\", \"hypothesis\": \"7B SFT Standard 20% HumanEval pass@1 @2048 v4 retry. Completes SFT column of 7B HumanEval matrix. Compare with GRPO Standard 10.98% and SFT CKA-only 20.12%. v3 failed due to process crash.\", \"parent\": \"eval_humaneval_sft_standard_20_2048_v3\", \"conclusion\": \"killed\"}, \"eval_humaneval_sft_rasp_20_2048_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T13:59:19.821Z\", \"updated_at\": \"2026-05-19T14:02:42.064Z\", \"hypothesis\": \"7B SFT RASP 20% HumanEval pass@1 @2048 v3 retry. Completes SFT column of 7B HumanEval matrix. Compare with GRPO RASP 10.98% and SFT CKA-only 20.12%. v2 failed due to startup issue.\", \"parent\": \"eval_humaneval_sft_rasp_20_2048\", \"conclusion\": \"killed\"}, \"eval_humaneval_sft_cka_only_20_2048_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T09:27:07.470Z\", \"updated_at\": \"2026-05-19T13:22:29.762Z\", \"hypothesis\": \"SFT CKA-only HumanEval v2 (PATH bug 修复版重跑)，验证 v1 的 0% 是否为假结果。v1 因 eval_humaneval.py 用裸 python 导致 164 题全部 sandbox 失败。修复后用 sys.executable 重跑。\", \"parent\": \"eval_humaneval_sft_cka_only_20_2048\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 20.12, \"n_correct\": 33, \"n_total\": 164}}, \"eval_math500_grpo_cka_only_20_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:36:14.421Z\", \"updated_at\": \"2026-05-19T13:08:18.617Z\", \"hypothesis\": \"GRPO CKA-only 20% MATH-500 accuracy with explicit max_new_tokens=2048. Re-eval for fair C1 OOD comparison: previous eval (26.6%) did not specify max_new_tokens. SFT CKA-only @2048 = 29.0%. If GRPO < SFT on MATH-500, C1 decoupling shows GRPO benefit is benchmark-dependent.\", \"parent\": \"eval_math500_grpo_cka_only_20\", \"metrics\": {\"accuracy\": 0.292, \"n_correct\": 146, \"n_total\": 500}, \"conclusion\": \"success\"}, \"eval_gsm8k_sft_standard_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:10:55.912Z\", \"updated_at\": \"2026-05-19T13:07:57.786Z\", \"hypothesis\": \"1.5B Standard post-SFT GSM8K accuracy (N=1319). SFT baseline for computing GRPO delta on Standard pruning at 1.5B scale. Compare with GRPO Standard 1.5B (22.29%) to quantify GRPO benefit. Completes 3-method SFT vs GRPO comparison at 1.5B.\", \"metrics\": {\"accuracy\": 0.22896133434420016, \"n_correct\": 302, \"n_total\": 1319}, \"conclusion\": \"success\"}, \"eval_gsm8k_grpo_standard_20_fair_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T09:27:09.334Z\", \"updated_at\": \"2026-05-19T12:47:36.437Z\", \"hypothesis\": \"验证 Standard GRPO fair (v5 config: beta=0.01, temp=0.4, maxlen=1024, DAPO, lr=1e-6) 的 GSM8K 准确率。替换 phantom 58.91% (从未被实际验证过的数字)。使用 grpo_stage2_standard_20_fair checkpoint, N=1319。\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 59.44, \"n_correct\": 784, \"n_total\": 1319}}, \"eval_humaneval_grpo_rasp_20_fair_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T06:38:59.146Z\", \"updated_at\": \"2026-05-19T09:44:43.320Z\", \"hypothesis\": \"HumanEval pass@1 for GRPO RASP 20% (fair model) with max_new_tokens=2048. Fair model trained with same setup as Standard/CKA-only for unbiased comparison on code generation.\", \"parent\": \"grpo_stage2_rasp_20_fair\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1098, \"n_correct\": 18, \"n_total\": 164, \"stderr\": 0.0244, \"avg_response_length\": null}}, \"eval_gsm8k_grpo_unstructured_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T04:46:38.286Z\", \"updated_at\": \"2026-05-19T08:05:04.224Z\", \"hypothesis\": \"GSM8K accuracy for GRPO-recovered unstructured 20% pruned model. Pre-GRPO baseline was 87.87%. Compare with structured GRPO results (CKA-only 64.37%, Standard 58.91%, RASP 56.71%) to quantify structured vs unstructured recovery dynamics.\", \"parent\": \"grpo_unstructured_20\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.8764, \"n_correct\": 1156, \"n_total\": 1319, \"stderr\": 0.00906, \"eos_rate\": 0.9818, \"truncated\": 24, \"avg_response_length\": 600}}, \"eval_humaneval_sft_cka_only_20_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T07:01:47.646Z\", \"updated_at\": \"2026-05-19T07:36:57.077Z\", \"metrics\": {\"pass_at_1\": 0, \"n_correct\": 0, \"n_total\": 164}, \"conclusion\": \"failed\", \"hypothesis\": \"SFT with CKA-only importance at 20% pruning ratio destroys code generation ability because CKA alone cannot identify layers critical for structured reasoning, resulting in near-zero HumanEval pass@1.\"}, \"eval_humaneval_grpo_cka_only_20_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T04:11:28.637Z\", \"updated_at\": \"2026-05-19T07:36:55.239Z\", \"hypothesis\": \"GRPO recovery training on CKA-only 20% pruned model recovers code generation ability on HumanEval from SFT baseline of 0% pass@1, because CKA-only preserves structural similarity that GRPO can exploit for cross-task recovery\", \"parent\": \"grpo_cka_only_20\", \"metrics\": {\"pass_at_1\": 0.2012, \"n_correct\": 33, \"n_total\": 164, \"stderr\": 0.0313, \"avg_response_length\": 1523.31, \"median_response_length\": 2048, \"wall_clock_seconds\": 11933}, \"conclusion\": \"success\"}, \"eval_humaneval_grpo_standard_20_fair_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T05:59:46.295Z\", \"updated_at\": \"2026-05-19T07:09:37.173Z\", \"hypothesis\": \"HumanEval pass@1 for GRPO Standard 20% (fair model) with max_new_tokens=2048. Previous eval used non-fair checkpoint (grpo_stage2_standard_20_v8, pass@1=10.37%). Fair model trained with same setup as CKA-only/RASP for unbiased comparison. Compare with SFT Standard @2048 (11.59%) and other pruning methods to verify recovery gradient on code generation.\", \"conclusion\": \"failed\", \"metrics\": {\"error\": \"model path not found: /root/autodl-tmp/recovery_aware_struct_prune/grpo_standard_20_fair — correct path is grpo_stage2_standard_20_fair\"}}, \"eval_humaneval_grpo_standard_20_fair_2048_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T06:39:01.302Z\", \"updated_at\": \"2026-05-19T06:42:53.032Z\", \"hypothesis\": \"HumanEval pass@1 for GRPO Standard 20% (fair model) with max_new_tokens=2048. Retry of v1 which failed due to wrong path (grpo_standard_20_fair vs grpo_stage2_standard_20_fair). Fair comparison with CKA-only/RASP.\", \"parent\": \"eval_humaneval_grpo_standard_20_fair_2048\", \"conclusion\": \"failed\"}, \"grpo_standard_20_fair\": {\"created_at\": \"2026-05-18T01:05:44.644Z\", \"hypothesis\": \"GRPO recovery training on standard-pruned 20% model (fair v5 config: beta=0.01, dapo loss, format_reward=0.1, temp=0.4, rep_penalty=1.15, adamw_bnb_8bit). Tests whether standard pruning + GRPO can recover GSM8K reasoning. Part of 4-method fair comparison (CKA-only, Standard, RASP, Random) under identical GRPO v4 config.\", \"parent\": \"grpo_rasp_20_fair\", \"status\": \"DONE\", \"updated_at\": \"2026-05-19T06:39:34.930Z\", \"metrics\": {\"wandb_run_id\": \"tyv20u2k\", \"total_steps\": 100, \"runtime_seconds\": 3017, \"reward_trajectory\": [0.051, 0.056, 0.067, 0.081, 0.019, 0.043, 0.047, 0.046, 0.031, 0.054], \"frac_zero_std_trajectory\": [0.5, 0.625, 0.5, 0.5, 0.575, 0.55, 0.575, 0.55, 0.55, 0.55], \"peak_reward\": 0.081, \"peak_reward_step\": 40, \"final_reward\": 0.054, \"final_frac_zero_std\": 0.55, \"dynamics_pattern\": \"dip_then_partial_recovery\", \"dip_step\": 50, \"dip_reward\": 0.019}, \"conclusion\": \"success\", \"notes\": \"Standard shows stagnation pattern: reward flat 0.03-0.08 全程无上升趋势, frac_zero_std stuck 0.5-0.55. 比 RASP (permanent collapse to 0.01 reward, frac_zero_std→0.85) 略好但也未恢复. 4-way gradient confirmed: CKA-only (active recovery) > Random (plateau) > Standard (stagnation) > RASP (permanent collapse). D058 fair comparison 完成.\"}, \"eval_gsm8k_grpo_standard_20_extended_300\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T05:57:41.667Z\", \"updated_at\": \"2026-05-19T05:58:27.139Z\", \"metrics\": {\"accuracy\": 0.5929, \"n_correct\": 782, \"n_total\": 1319, \"eos_rate\": 0.9795, \"avg_response_length\": 229.57, \"stderr\": 0.01353}, \"conclusion\": \"negative\", \"hypothesis\": \"Standard pruning 20% with extended GRPO training (300 steps) will not recover GSM8K accuracy beyond the 100-step level (~52-53%), because the reward collapse observed during training prevents meaningful downstream improvement regardless of additional training steps.\"}, \"grpo_unstructured_20\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-19T04:41:30.397Z\", \"updated_at\": \"2026-05-19T04:43:46.698Z\", \"conclusion\": \"failed\", \"notes\": \"失败原因: torch.save optimizer state 时 IOException (RuntimeError: basic_ios::clear: iostream error + enforce fail at inline_container.cc:668, pos mismatch 10100272512 vs 10100272408)。模型 shard 保存成功但 ~9.4GB optimizer state 写入失败。可能是磁盘空间不足或文件系统限制。需检查 westb-23072 /root/autodl-tmp 分区空间，修复后重试。\"}, \"eval_gsm8k_grpo_cka_only_20_extended_300\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T01:42:30.325Z\", \"updated_at\": \"2026-05-19T03:49:12.498Z\", \"hypothesis\": \"Extended GRPO training (300 steps vs 100 steps) on CKA-only 20% pruned model will further improve GSM8K in-distribution accuracy beyond the 64.37% achieved at 100 steps\", \"parent\": \"grpo_cka_only_20_extended_300\", \"metrics\": {\"gsm8k_accuracy\": 0.6437, \"correct\": 849, \"total\": 1319, \"stderr\": 0.0132, \"eos_rate\": 0.9924, \"avg_response_length\": 190.45}, \"conclusion\": \"negative\"}, \"inference_bench_clean_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T01:42:25.421Z\", \"updated_at\": \"2026-05-19T02:44:07.178Z\", \"hypothesis\": \"Clean inference benchmark (Dense + CKA-only 20% + Standard 20%) on isolated GPU. Previous plan_016 benchmark was polluted by GPU contention. Measures per-token throughput and latency for speedup claims. 50 prompts x 256 max_new_tokens, GSM8K test set.\", \"conclusion\": \"success\", \"metrics\": {\"original_tps\": 72.02, \"cka_only_20_tps\": 58.28, \"standard_20_tps\": 58.25, \"cka_only_20_speedup\": 0.809, \"standard_20_speedup\": 0.809, \"original_first_token_ms\": 20.05, \"cka_only_20_first_token_ms\": 16.35, \"standard_20_first_token_ms\": 16.4, \"original_per_token_ms\": 13.89, \"cka_only_20_per_token_ms\": 16.73, \"standard_20_per_token_ms\": 16.71, \"original_params\": 7615616512, \"pruned_params\": 6161946112, \"param_reduction_pct\": 19.1}}, \"eval_gsm8k_sft_rasp_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:10:57.471Z\", \"updated_at\": \"2026-05-19T02:43:38.445Z\", \"hypothesis\": \"1.5B RASP post-SFT GSM8K accuracy (N=1319). SFT baseline for computing GRPO delta on RASP pruning at 1.5B. Compare with GRPO RASP 1.5B (26.16%).\", \"parent\": \"sft_rasp_20_1p5b\", \"metrics\": {\"accuracy\": 0.2691, \"n_correct\": 355, \"n_total\": 1319, \"stderr\": 0.0122, \"grpo_delta_pp\": -0.75}, \"conclusion\": \"success\"}, \"eval_math500_grpo_standard_20_fair_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:24:25.108Z\", \"updated_at\": \"2026-05-19T01:39:52.608Z\", \"hypothesis\": \"Standard 20% post-GRPO (fair v5) MATH-500 accuracy with max_new_tokens=2048. Restart of slow original. Interim Acc@100=36%. Cross-benchmark validation for C1 decoupling claim.\", \"parent\": \"eval_math500_grpo_standard_20_fair\", \"metrics\": {\"accuracy\": 0.264, \"n_correct\": 132, \"n_total\": 500, \"stderr\": 0.0197}, \"conclusion\": \"success\"}, \"eval_math500_sft_rasp_20_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:36:16.836Z\", \"updated_at\": \"2026-05-19T01:39:03.294Z\", \"hypothesis\": \"SFT RASP 20% MATH-500 accuracy with max_new_tokens=2048. Fair comparison with GRPO RASP @2048 (24.0%) for C1 decoupling on MATH-500. SFT recovery should show lower reasoning capability than GRPO recovery on structurally pruned model.\", \"parent\": \"eval_math500_sft_rasp_20\", \"metrics\": {\"accuracy\": 0.226, \"n_correct\": 113, \"n_total\": 500, \"stderr\": 0.0187, \"natural_eos\": 314, \"truncated\": 186, \"natural_eos_pct\": 0.628, \"avg_response_length\": 930.58, \"median_response_length\": 274}, \"conclusion\": \"success\"}, \"eval_math500_dense_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:08:58.081Z\", \"updated_at\": \"2026-05-19T01:34:41.598Z\", \"hypothesis\": \"Dense (unpruned) DeepSeek-R1-Distill-Qwen-7B MATH-500 eval with max_new_tokens=2048. Fair comparison baseline for all pruned model MATH-500 evals which also use 2048 max tokens. Previous Dense baseline (73.6%) used 4096 tokens.\", \"parent\": \"eval_math500_dense_unpruned\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.53, \"n_correct\": 265, \"n_total\": 500, \"stderr\": 0.0223, \"natural_eos_pct\": 0.468, \"truncated_pct\": 0.532, \"avg_response_length\": 1724.5, \"median_response_length\": 2048}}, \"eval_math500_grpo_rasp_20_fair\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:16:25.616Z\", \"updated_at\": \"2026-05-18T23:53:54.384Z\", \"hypothesis\": \"GRPO RASP 20% pruned model on MATH-500 with max_new_tokens=2048. Fair comparison for C1 decoupling: GRPO recovery on RASP-pruned model should show different accuracy profile compared to SFT recovery, measuring reasoning capability after RL-based fine-tuning on structurally pruned model.\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.24, \"n_correct\": 120, \"n_total\": 500, \"stderr\": 0.0191, \"natural_eos_pct\": 0.64, \"truncated_pct\": 0.36, \"avg_response_length\": 903.5, \"median_response_length\": 272, \"max_new_tokens\": 2048}}, \"eval_gsm8k_sft_cka_only_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T17:51:20.577Z\", \"updated_at\": \"2026-05-18T23:46:01.152Z\", \"hypothesis\": \"1.5B CKA-only post-SFT GSM8K accuracy (N=1319). SFT baseline for computing GRPO delta: if GRPO CKA-only 1.5B GSM8K > SFT CKA-only 1.5B GSM8K, GRPO adds value beyond SFT recovery on 1.5B scale. Completes C1 decoupling evidence at 1.5B.\", \"parent\": \"sft_cka_only_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.3563, \"n_correct\": 470, \"n_total\": 1319, \"stderr\": 0.0132, \"eos_rate\": 0.9507, \"avg_response_length\": 336.76}}, \"sft_standard_20_retrain_westd\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:40:50.567Z\", \"updated_at\": \"2026-05-18T23:24:15.076Z\", \"hypothesis\": \"Retrain SFT Standard 20% on westd from pruned_standard_20. Original sft_standard_20 model lost (was on old westd-11672). Needed for eval_math500_sft_standard_20_2048 with correct model.\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.758, \"mean_token_accuracy\": 0.8252, \"train_runtime_sec\": 1688, \"train_samples_per_second\": 8.856, \"epochs\": 2, \"total_steps\": 1870}}, \"eval_math500_sft_standard_20_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:18:30.238Z\", \"updated_at\": \"2026-05-18T23:19:30.781Z\", \"hypothesis\": \"SFT Standard 20% MATH-500 accuracy with max_new_tokens=2048. Fair comparison with GRPO Standard @2048 for C1 decoupling claim on harder benchmark.\", \"parent\": \"eval_math500_sft_standard_20\", \"conclusion\": \"killed\"}, \"eval_gsm8k_grpo_rasp_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T16:59:22.921Z\", \"updated_at\": \"2026-05-18T23:02:00.110Z\", \"hypothesis\": \"1.5B RASP post-GRPO GSM8K accuracy (N=1319). Cross-model generalization: 7B RASP GRPO collapsed (reward 0.01), but 1.5B RASP showed reward=0.099 without collapse. If 1.5B RASP GSM8K is lower than CKA-only but not catastrophically low, confirms scale-dependent recovery dynamics. Completes 3-method 1.5B GSM8K comparison.\", \"parent\": \"grpo_rasp_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.2616, \"n_correct\": 345, \"n_total\": 1319, \"stderr\": 0.0121, \"eos_rate\": 0.9378, \"avg_response_length\": 392.7}}, \"eval_math500_sft_cka_only_20_v4_restart\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:16:24.171Z\", \"updated_at\": \"2026-05-18T22:12:04.614Z\", \"hypothesis\": \"CKA-only 20% post-SFT MATH-500 accuracy (restart of v4 which had cuda:2 conflict). Full 500 samples, max_new_tokens=2048. Core C1 evidence for decoupling claim.\", \"parent\": \"eval_math500_sft_cka_only_20_v4\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.29, \"n_correct\": 145, \"n_total\": 500, \"stderr\": 0.0203, \"natural_eos\": 384, \"truncated\": 116, \"natural_eos_pct\": 0.768, \"avg_response_length\": 673.278, \"median_response_length\": 242.5}}, \"grpo_cka_only_20_extended_300\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T14:51:36.423Z\", \"updated_at\": \"2026-05-18T21:43:18.847Z\", \"hypothesis\": \"Extended GRPO CKA-only 7B from step 100 to 300. Paired control for E2 Standard extended: if CKA-only continues improving while Standard enters reward desert, proves CKA-only's structural advantage persists under longer training. Standard showed reward decline after step 260 (0.102→0.056); CKA-only's peak at step 100 was 0.354 — expect continued learning.\", \"parent\": \"grpo_cka_only_20\", \"conclusion\": \"success\", \"metrics\": {\"final_reward\": 0.3075, \"peak_reward\": 0.4444, \"peak_reward_step\": 280, \"reward_step100\": 0.354, \"reward_step300\": 0.3075, \"train_loss_final\": 0.0349, \"global_step\": 300, \"runtime_seconds\": 23004, \"gpu_hours\": 6.5, \"final_frac_zero_std\": 0.275, \"reward_range\": [0.22, 0.44], \"pattern\": \"sustained oscillation, no collapse\", \"wandb_run_id\": \"z9f0z901\"}}, \"eval_gsm8k_grpo_standard_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T16:38:01.585Z\", \"updated_at\": \"2026-05-18T21:03:21.558Z\", \"hypothesis\": \"Standard GRPO 1.5B (100 steps, reward=0.084) on GSM8K eval: expect low accuracy (~5-10%) given minimal training, serving as baseline for pruned model comparison.\", \"parent\": \"grpo_standard_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.2229, \"n_correct\": 294, \"n_total\": 1319, \"stderr\": 0.0115}}, \"eval_gsm8k_grpo_cka_only_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T16:35:29.923Z\", \"updated_at\": \"2026-05-18T20:09:40.771Z\", \"hypothesis\": \"1.5B CKA-only post-GRPO GSM8K accuracy (N=1319). Cross-model generalization: 7B CKA-only GRPO achieved 64.37% GSM8K. If 1.5B CKA-only GRPO also leads among pruning methods, confirms scale-invariant recovery capacity gradient. Parent: grpo_cka_only_20_1p5b (reward=0.2375, highest among 1.5B methods).\", \"parent\": \"grpo_cka_only_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.3548, \"n_correct\": 468, \"n_total\": 1319, \"stderr\": 0.0132}}, \"eval_math500_sft_cka_only_20_v4\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T17:05:46.843Z\", \"updated_at\": \"2026-05-18T18:16:11.156Z\", \"hypothesis\": \"CKA-only 20% post-SFT MATH-500 accuracy (full 500 samples). C1 core evidence: compare with GRPO CKA-only MATH-500 to test decoupling. If post-GRPO > post-SFT on MATH-500, CKA-only uniquely benefits from GRPO on harder benchmarks. v3 timed out at 170/500 (36.67% interim). v4 removes timeout, adds --max_new_tokens 2048.\", \"parent\": \"eval_math500_sft_cka_only_20_v3\", \"conclusion\": \"failed\"}, \"eval_math500_dense_unpruned\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T13:42:10.786Z\", \"updated_at\": \"2026-05-18T18:15:28.383Z\", \"hypothesis\": \"Dense unpruned DeepSeek-R1-Distill-Qwen-7B MATH-500 baseline. Establishes upper bound for all pruned model MATH-500 evaluations. Previous result on westd showed 73.6%; this is a verification run on westd-29022.\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.736, \"stderr\": 0.0197, \"n_correct\": 368, \"n_total\": 500, \"natural_eos_pct\": 0.752}}, \"eval_math500_grpo_standard_20_fair\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T13:38:06.779Z\", \"updated_at\": \"2026-05-18T18:09:33.985Z\", \"hypothesis\": \"Standard 20% post-GRPO MATH-500 accuracy (fair v5 config). Cross-benchmark validation: if Standard GRPO shows same decoupling pattern on MATH-500 as GSM8K (post-GRPO ≈ post-SFT), confirms C1 decoupling is not benchmark-specific.\", \"parent\": \"grpo_standard_20_fair\", \"notes\": \"v1: 126/500 completed (Acc@100=36.0%), killed SIGHUP after 4h44m. v2: restarted with --max_new_tokens 2048, died silently at 19/500 with no error/Traceback/OOM in log. Cron detected process dead 5× → auto-resolved failed. Need diagnostic: check dmesg for OOM killer, GPU memory, tmux session status. Interim data: Acc@100=36.0% from v1.\", \"conclusion\": \"failed\"}, \"eval_math500_sft_cka_only_20_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T13:39:24.314Z\", \"updated_at\": \"2026-05-18T17:04:00.609Z\", \"hypothesis\": \"CKA-only 20% post-SFT MATH-500 accuracy. C1 validation: compare with GRPO CKA-only MATH-500 to test if GRPO genuinely helps CKA-only on harder benchmark. If post-GRPO > post-SFT on MATH-500, CKA-only is unique in benefiting from GRPO (unlike Standard/RASP decoupling).\", \"parent\": \"sft_cka_only_20\", \"conclusion\": \"failed\"}, \"grpo_rasp_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T15:12:41.395Z\", \"updated_at\": \"2026-05-18T16:32:13.529Z\", \"hypothesis\": \"RASP 20% GRPO on 1.5B model. Cross-model generalization: 7B RASP collapsed to reward 0.01, frac_zero_std 0.85. If 1.5B shows same collapse pattern, confirms scale-invariant recovery capacity gradient bottom tier. Completes 3-method 1.5B comparison: CKA-only (reward ~0.26) >> Standard (0.08) >> RASP (expected collapse).\", \"parent\": \"sft_rasp_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"final_reward\": 0.099, \"frac_zero_std\": 0.175, \"clipped_ratio\": 0.82}}, \"grpo_cka_only_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T12:50:08.570Z\", \"updated_at\": \"2026-05-18T16:08:40.491Z\", \"hypothesis\": \"CKA-only 20% GRPO on 1.5B model. Cross-model generalization: if CKA-only's superior GRPO dynamics (peak reward 0.354 on 7B) hold on 1.5B, confirms scale-invariant recovery capacity gradient. Parent: sft_cka_only_20_1p5b.\", \"parent\": \"sft_cka_only_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"reward_mean\": 0.2375, \"frac_reward_zero_std\": 0.175, \"loss\": 0.0595, \"kl\": 0.00215, \"grad_norm\": 1.445, \"global_step\": 100, \"note\": \"training completed 100/100 but save_model failed (disk full). checkpoint-100 has complete model.\"}}, \"grpo_standard_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T14:15:13.990Z\", \"updated_at\": \"2026-05-18T15:11:31.870Z\", \"hypothesis\": \"Standard 20% GRPO on 1.5B model. Cross-model generalization: if Standard's dip-then-recovery GRPO dynamics (peak 0.081, dip 0.019 on 7B) hold on 1.5B, confirms scale-invariant recovery capacity gradient. Paired with CKA-only 1.5B GRPO for direct comparison.\", \"parent\": \"sft_standard_20_1p5b\", \"metrics\": {\"reward_mean\": 0.0844, \"frac_reward_zero_std\": 0.15, \"loss\": 0.0151, \"grad_norm\": 4.03125, \"kl\": 0.0044, \"entropy\": 0.4617, \"final_step\": 100, \"max_steps\": 100, \"total_time_min\": 53}, \"conclusion\": \"success\"}, \"grpo_standard_20_extended_300_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T13:53:41.781Z\", \"updated_at\": \"2026-05-18T14:50:59.377Z\", \"hypothesis\": \"Extended GRPO Standard 7B from step 110 to 300 (resumed after disk-full crash at step 120). Tests whether longer GRPO training changes the recovery capacity gradient. save_steps=50, save_total_limit=3 to prevent disk issues.\", \"parent\": \"grpo_standard_20_extended_300\", \"metrics\": {\"reward_mean_step300\": 0.0562, \"loss_step300\": 0.0367, \"frac_reward_zero_std_step300\": 0.525, \"kl_step300\": 0.00306, \"entropy_step300\": 0.157, \"lr_step300\": 3.33e-09, \"runtime_min\": 48, \"reward_decline_after_step260\": true}, \"conclusion\": \"success\"}, \"grpo_standard_20_extended_300\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T13:40:13.842Z\", \"updated_at\": \"2026-05-18T14:47:58.809Z\", \"hypothesis\": \"Extended GRPO Standard 7B from step 100 to 300. Tests whether longer GRPO training changes the recovery capacity gradient — does Standard eventually catch up to CKA-only, or does the gap persist/widen? If gap widens, confirms CKA-guided pruning creates a structural advantage that more training cannot compensate.\", \"parent\": \"grpo_standard_20_fair\", \"conclusion\": \"failed\"}, \"grpo_standard_1p5b_100steps\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-18T14:11:59.512Z\", \"updated_at\": \"2026-05-18T14:11:59.512Z\"}, \"e2_extended_grpo_resume\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-18T13:47:47.352Z\", \"updated_at\": \"2026-05-18T13:47:47.353Z\"}, \"math500_dense_unpruned\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-18T13:19:07.873Z\", \"updated_at\": \"2026-05-18T13:19:07.873Z\"}, \"E2_grpo_standard_7b_extended_300\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-18T13:02:30.174Z\", \"updated_at\": \"2026-05-18T13:02:30.174Z\"}, \"math500_sft_cka_only_20\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-18T13:01:43.349Z\", \"updated_at\": \"2026-05-18T13:01:43.349Z\"}, \"math500_standard_grpo_fair\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-18T13:00:45.510Z\", \"updated_at\": \"2026-05-18T13:00:45.510Z\"}, \"sft_standard_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T12:09:56.278Z\", \"updated_at\": \"2026-05-18T12:31:29.300Z\", \"hypothesis\": \"Standard 20% SFT recovery on 1.5B model. Cross-model generalization test: if Standard SFT recovery pattern holds on 1.5B as on 7B. Paired with CKA-only and RASP 1.5B SFT for cross-scale comparison of recovery capacity gradient.\", \"conclusion\": \"success\"}, \"sft_cka_only_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T11:29:09.842Z\", \"updated_at\": \"2026-05-18T12:31:27.978Z\", \"hypothesis\": \"CKA-only 20% SFT recovery on 1.5B model. Cross-model generalization test: if CKA-only SFT recovery pattern (high accuracy) holds on 1.5B as on 7B, validates that CKA-guided pruning preserves recovery capacity across model scales.\", \"notes\": \"Training completed 1870/1870 steps. Checkpoint save crashed (RuntimeError at inline_container.cc:668) due to disk 100% full. Model weights rescued from checkpoint-1870 (optimizer.pt truncated but model.safetensors intact). Checkpoints cleaned, model files promoted to output dir. Pending load validation.\", \"conclusion\": \"success\"}, \"sft_rasp_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T12:09:57.178Z\", \"updated_at\": \"2026-05-18T12:29:19.746Z\", \"hypothesis\": \"RASP 20% SFT recovery on 1.5B model. Cross-model generalization test: if RASP SFT recovery pattern holds on 1.5B as on 7B. Paired with CKA-only and Standard 1.5B SFT for cross-scale comparison of recovery capacity gradient.\", \"conclusion\": \"success\"}, \"inference_bench_cka_only_20_clean\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T09:47:42.247Z\", \"updated_at\": \"2026-05-18T10:07:56.924Z\", \"hypothesis\": \"Clean CKA-only inference benchmark (rerun after GPU contention in v1). Validates CKA-only latency/memory vs dense baseline on clean cuda:0. Dense dummy in rasp slot (rasp model not on westb).\", \"parent\": \"inference_bench_cka_only_20\", \"metrics\": {\"dense\": {\"tokens_per_second\": 75.73, \"avg_latency_sec\": 6.729, \"peak_memory_gb\": 16.22, \"total_tokens\": 25477, \"validation\": \"PASS (75.73 vs expected 76.25, <1% deviation)\"}, \"cka_only_20\": {\"tokens_per_second\": 51.86, \"avg_latency_sec\": 4.078, \"peak_memory_gb\": 11.6, \"total_tokens\": 10574, \"latency_speedup_vs_dense\": \"39.4%\", \"memory_reduction_vs_dense\": \"28.5%\"}, \"rasp_20_dummy\": {\"tokens_per_second\": 75.79, \"avg_latency_sec\": 6.723, \"peak_memory_gb\": 16.23, \"note\": \"Dense model used as dummy (rasp not on westb)\"}}, \"conclusion\": \"success\"}, \"inference_bench_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T08:09:24.237Z\", \"updated_at\": \"2026-05-18T08:51:24.419Z\", \"hypothesis\": \"CKA-only inference latency benchmark. Compare CKA-only pruned model vs dense on tokens/s, latency, memory. Uses dense as dummy for rasp slot (rasp model not on westb). CKA-only in standard_20 slot.\", \"metrics\": {\"dense_contaminated\": {\"tokens_per_second\": 35.4, \"avg_latency_sec\": 14.396, \"peak_memory_gb\": 16.22, \"note\": \"GPU contention with GSM8K eval — 2.15x slower than clean baseline (6.682s)\"}, \"cka_only_20\": {\"tokens_per_second\": 51.01, \"avg_latency_sec\": 4.146, \"peak_memory_gb\": 11.6, \"total_tokens\": 10574, \"note\": \"Ran after GSM8K finished, likely clean. Memory reduction 28.5% vs dense.\"}, \"contamination_warning\": \"Dense baseline 14.396s vs clean 6.682s. Benchmark needs rerun with clean GPU for valid dense comparison.\"}, \"conclusion\": \"failed\"}, \"eval_gsm8k_grpo_cka_only_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T05:54:02.634Z\", \"updated_at\": \"2026-05-18T08:50:27.816Z\", \"hypothesis\": \"CKA-only GRPO GSM8K accuracy (v2, on westb). Tab2 critical data point: if CKA-only GRPO > SFT (63.91%), GRPO genuinely helps CKA-only recovery. Re-run after westd outage killed v1.\", \"parent\": \"eval_gsm8k_grpo_cka_only_20\", \"metrics\": {\"accuracy\": 0.6437, \"n_correct\": 849, \"n_total\": 1319, \"stderr\": 0.0132, \"eos_rate\": 0.9886, \"avg_response_length\": 203.43, \"truncated\": 15, \"wall_time_sec\": 8921}, \"conclusion\": \"success\"}, \"eval_math500_grpo_unpruned\": {\"created_at\": \"2026-05-17T18:14:45.810Z\", \"hypothesis\": \"MATH-500 accuracy for unpruned GRPO v2 (step-100). Establishes MATH-500 baseline: if unpruned post-GRPO ≈ 73.6% (pre-GRPO), confirms decoupling pattern holds on harder benchmark. If higher, GRPO genuinely helps unpruned but not pruned = pruning-specific failure.\", \"parent\": \"eval_math500_unpruned\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T08:32:50.722Z\", \"metrics\": {\"accuracy\": 0.69, \"n_correct\": 345, \"n_total\": 500, \"stderr\": 0.0207, \"avg_response_length\": 1768.07, \"median_response_length\": 1420.5, \"natural_eos_pct\": 0.828, \"truncated\": 86, \"wall_time_sec\": 20685}, \"conclusion\": \"negative\"}, \"scoring_ablation_magnitude_20\": {\"created_at\": \"2026-05-17T04:21:41.038Z\", \"hypothesis\": \"Magnitude-only scoring (weight L2 norm per group) at 20% sparsity. Isolates contribution of gradient signal vs weight magnitude. If post-prune accuracy near 0% (as expected from heavy early-layer pruning), confirms magnitude alone is insufficient for structured pruning — CKA/gradient signals are essential.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T05:52:12.799Z\", \"conclusion\": \"failed\"}, \"eval_gsm8k_grpo_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T05:06:54.386Z\", \"updated_at\": \"2026-05-18T05:21:38.616Z\", \"hypothesis\": \"GRPO with CKA-only recovery (20 steps) preserves GSM8K math reasoning accuracy compared to unpruned baseline, because CKA alignment guides recovery to restore the most task-critical representations in pruned layers.\", \"conclusion\": \"failed\", \"notes\": \"westd-11672 服务器不可达，实验状态未知。等服务器恢复后检查。\"}, \"eval_math500_grpo_standard_20\": {\"created_at\": \"2026-05-17T09:27:18.869Z\", \"hypothesis\": \"MATH-500 accuracy for grpo_standard_20 vs sft_standard_20. If grpo_standard ≈ sft_standard on MATH-500 (as on GSM8K), C1 decoupling holds across benchmarks. Tests cross-benchmark generalization of C1.\", \"parent\": \"eval_math500_sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T05:21:37.574Z\", \"notes\": \"失败原因: westd-11672 服务器不可达 (SSH connection refused on port 11672) | 进度: ~359/500 before disconnect | 建议: 等 westd 恢复后检查部分结果\", \"conclusion\": \"failed\"}, \"eval_math500_sft_cka_only_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T02:40:23.649Z\", \"updated_at\": \"2026-05-18T05:21:34.598Z\", \"hypothesis\": \"CKA-only SFT MATH-500 baseline (restart from cuda:2→cuda:0 for speed). With SFT Standard=26%, SFT RASP=24.2%, if CKA-only SFT > 26%, CKA-only scoring has OOD advantage.\", \"parent\": \"eval_math500_sft_cka_only_20\", \"conclusion\": \"failed\", \"notes\": \"失败原因: westd-11672 服务器不可达 (SSH connection refused on port 11672) | 非代码问题，基础设施故障 | 已有成果: 无法确认（服务器离线前可能有部分进度） | 建议: 等 westd 恢复后检查 /root/autodl-tmp/recovery_aware_struct_prune/results/math500_sft_cka_only_20.json 是否有部分结果，有则恢复，无则在可用 GPU 上重跑\"}, \"eval_math500_grpo_rasp_20_v3\": {\"created_at\": \"2026-05-17T14:44:46.855Z\", \"hypothesis\": \"MATH-500 accuracy for grpo_rasp_20 (grpo_stage2_rasp_20_v9). v2 timeout at 193/500 (EXIT_CODE=124, 6h limit). v3 without timeout wrapper. If GRPO RASP outperforms SFT RASP on MATH-500, GRPO adds reasoning. If not, reinforces C1 decoupling.\", \"parent\": \"eval_math500_grpo_rasp_20_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T05:19:01.331Z\", \"conclusion\": \"failed\"}, \"grpo_cka_only_20\": {\"created_at\": \"2026-05-17T14:51:36.653Z\", \"hypothesis\": \"CKA-only pruning removes highest functional overlap first (post-prune 38.5% = least damage). Predicts GRPO collapse faster than RASP due to fewer backup paths. If confirmed, this is direct evidence of Redundancy-Stability Tradeoff: post-prune optimal = GRPO least stable.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T02:21:23.748Z\", \"metrics\": {\"final_step\": 100, \"final_reward\": 0.3444, \"peak_reward\": 0.3544, \"peak_reward_step\": 50, \"final_frac_zero_std\": 0.2, \"final_loss\": 0.23, \"final_kl\": 0.001609, \"final_entropy\": 0.08751, \"final_reward_std\": 0.444, \"runtime_seconds\": 40710}, \"conclusion\": \"success\"}, \"grpo_rasp_20_fair\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T23:50:31.502Z\", \"hypothesis\": \"Fair retrain of GRPO on RASP 20% pruned model using v5 config (same as CKA-only/Random). Resolves D058 confound: if RASP GRPO dynamics under v5 config show similar reward stagnation as original (old config), confirms the recovery capacity gradient is real and not an artifact of config differences.\", \"metrics\": {\"final_completion_length\": 963.0, \"final_frac_zero_std\": 0.85, \"final_reward\": 0.01, \"min_frac_zero_std\": 0.675, \"peak_reward\": 0.061, \"total_steps\": 100, \"training_time_minutes\": 62.5, \"trend\": \"stagnation_then_collapse\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-18T01:08:19.563Z\"}, \"eval_postprune_standard_30\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T19:08:46.051Z\", \"hypothesis\": \"Standard 30% post-prune GSM8K accuracy (N=200). At 20% Standard post-prune was 17.5%, at 25% was ~15%. 30% should show further degradation. Compared with RASP 30% post-prune (running) to verify RASP advantage persists at higher sparsity. Extends multi-sparsity degradation curve.\", \"metrics\": {\"avg_response_length\": 3907.875, \"correct\": 8, \"eos_rate\": 0.055, \"gsm8k_accuracy\": 0.04, \"natural_eos\": 11, \"total\": 200, \"truncated\": 189}, \"parent\": \"prune_standard_30\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T00:27:39.362Z\"}, \"eval_sft_cka_only_20_n1319\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T18:20:20.406Z\", \"hypothesis\": \"CKA-only pruning preserves more recoverable structure than RASP/Standard, so post-SFT accuracy should be highest among all 20% pruning methods on full GSM8K (N=1319).\", \"metrics\": {\"avg_response_length\": 198.1, \"correct\": 843, \"eos_rate\": 0.9901, \"gsm8k_accuracy\": 0.6391, \"stderr\": 0.0132, \"total\": 1319}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T23:48:58.392Z\"}, \"eval_postprune_cka_only_30\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-17T21:42:07.999Z\", \"hypothesis\": \"CKA-only 30% post-prune accuracy. If > 0% (vs RASP 30% = 0%), proves representational diversity scoring is more robust at high sparsity than composite scoring (RASP). If also = 0%, cliff is sparsity-universal regardless of scoring method. Supports C2 collapse gradient + sparsity range analysis.\", \"metrics\": {\"gsm8k_accuracy\": 0.0, \"note\": \"Killed by Director: 30% cliff already confirmed 0% in first run. Kill to free cuda:2.\"}, \"notes\": \"失败原因: ValueError - tokenizer.chat_template not set. 剪枝模型目录 pruned_cka_only_30 缺少 tokenizer 文件(已知问题,见 memory.md tokenizer 同步问题). fix_worker_id: worker_fix_eval_postprune_cka_only_30_20260517T215905. 自动修复中：复制 tokenizer 文件后重提交.\", \"parent\": \"prune_cka_only_30\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T22:00:33.735Z\"}, \"prune_cka_only_30\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T21:42:06.467Z\", \"hypothesis\": \"CKA-only pruning at 30% sparsity. CKA-only 20% had highest post-prune accuracy (38.5%). At 30%, if still > 0% (vs RASP 30% = 0%), proves representational diversity scoring is more robust at high sparsity than composite scoring.\", \"metrics\": {\"actual_sparsity\": 0.2892, \"attn_heads_pruned\": \"0\", \"method\": \"dummy_ones_importance + rasp_alpha1 = pure CKA-only\", \"mlp_groups_pruned\": \"303/784\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T21:42:06.467Z\"}, \"eval_postprune_rasp_30\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T18:22:00Z\", \"hypothesis\": \"RASP 30% post-prune GSM8K accuracy (N=200). At 20% RASP post-prune was 29%, at 25% was 21%. 30% should be lower. Establishes degradation curve for multi-sparsity analysis.\", \"metrics\": {\"accuracy\": 0, \"avg_response_length\": 3984.31, \"eos_rate\": 0.03, \"n_correct\": 0, \"n_total\": 200, \"natural_eos\": 6, \"truncated_rate\": 0.97}, \"notes\": \"实际完成全部 200 样本，EXIT_CODE=129 是 SSH 断连（SIGHUP），非真正失败。结果：accuracy=0.0%，97% 样本被截断（avg_len=3984/4096），模型在 30% sparsity 完全崩溃。降级曲线：29%(20%) → 21%(25%) → 0%(30%)，25%-30% 间存在 cliff。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T21:39:43.149Z\"}, \"eval_sft_cka_only_20_full_v2\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-17T19:37:17.403Z\", \"hypothesis\": \"CKA-only 20% post-SFT GSM8K N=1319. v1 failed (model not on westd). Model now synced. Post-prune 38.5% highest, if post-SFT also highest then CKA-only scoring has SFT advantage; if converges to ~60% confirms SFT equalizes. N=200 pilot showed 64.0%.\", \"parent\": \"eval_sft_cka_only_20_full\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T19:37:21.325Z\"}, \"eval_humaneval_sft_standard_20_2048_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T16:26:15.836Z\", \"hypothesis\": \"HumanEval pass@1 for SFT Standard 20% with max_new_tokens=2048. Completes 5-way HumanEval@2048 matrix. Compares SFT Standard vs SFT RASP (10.37%) code generation after recovery.\", \"metrics\": {\"avg_response_length\": 1850.7, \"correct\": 19, \"max_new_tokens\": 2048, \"median_response_length\": 2048, \"pass_at_1\": 0.1159, \"total\": 164}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T19:09:18.456Z\"}, \"eval_sft_cka_only_20_full\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T18:22:00Z\", \"hypothesis\": \"CKA-only 20% post-SFT GSM8K N=1319. post-prune 38.5% highest, if post-SFT also highest then CKA-only scoring has SFT advantage; if converges to ~60% confirms SFT equalizes. N=200 pilot showed 64.0%.\", \"notes\": \"失败原因: EXIT_CODE=1 — AutoTokenizer.from_pretrained 无法加载 /root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20 的 tokenizer（目录缺少 tokenizer 文件或不存在）。transformers fallback 到 HuggingFace Hub 下载时路径格式无效报错。| 类型: infrastructure | 已派 Worker 诊断修复\", \"parent\": \"eval_sft_cka_only_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T19:04:34.857Z\"}, \"eval_humaneval_grpo_standard_20_2048\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T13:41:03.761Z\", \"hypothesis\": \"HumanEval pass@1 for GRPO Standard 20% with max_new_tokens=2048. 512-token results invalidated due to truncation artifact (RASP shorter outputs biased). Part of complete 4-way HumanEval@2048 comparison: unpruned / SFT RASP / GRPO Standard / GRPO RASP.\", \"metrics\": {\"avg_response_length\": 1843, \"correct\": 17, \"max_new_tokens\": 2048, \"median_response_length\": 2048, \"pass_at_1\": 0.1037, \"total\": 164}, \"parent\": \"eval_humaneval_grpo_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T18:16:11.481Z\"}, \"eval_math500_sft_rasp_25\": {\"created_at\": \"2026-05-17T18:14:47.071Z\", \"hypothesis\": \"MATH-500 accuracy for RASP 25% post-SFT. Extends MATH-500 cross-benchmark data to 25% sparsity. If MATH-500 recovery rate at 25% &lt; 20% (RASP 20% SFT = 24.2%), confirms sparsity gradient on harder benchmark. Parent: sft_rasp_25.\", \"parent\": \"sft_rasp_25\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T18:14:58.996Z\"}, \"grpo_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:42:40.256Z\", \"hypothesis\": \"RASP 25% GRPO recovery (100 steps). 预期 collapse 比 20% 更快更严重。与 grpo_standard_25 对比验证 C3: recovery method conditions pruning order. Parent: sft_rasp_25.\", \"metrics\": {\"note\": \"Restored from previous_failure — cron false positive, experiment actually completed 100/100 steps successfully\", \"step_100\": {\"entropy\": 0.04262, \"frac_reward_zero_std\": 0.875, \"grad_norm\": 0.05371, \"kl\": 0.0007035, \"loss\": 0.01275, \"reward\": 0.009375, \"reward_std\": 0.03149}, \"wall_clock_min\": 57.95, \"wandb_run_id\": \"bc4ojqie\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T18:06:56.419Z\"}, \"eval_humaneval_grpo_rasp_20_2048\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T13:41:44.795Z\", \"hypothesis\": \"HumanEval pass@1 for GRPO RASP 20% with max_new_tokens=2048. Completes 4-way HumanEval@2048 matrix. If GRPO RASP > GRPO Standard on code generation, reinforces C3 (RASP preserves transferable structures). Queued for westd cuda:0 after unpruned 2048 completes.\", \"metrics\": {\"correct\": 24, \"max_new_tokens\": 2048, \"pass_at_1\": 0.1463, \"stderr\": 0.0276, \"total\": 164}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T16:24:44.117Z\"}, \"eval_math500_grpo_rasp_20_v2\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T08:34:15.861Z\", \"hypothesis\": \"MATH-500 accuracy for grpo_rasp_20 (grpo_stage2_rasp_20_v9) vs sft_rasp_20. If GRPO adds math reasoning beyond SFT recovery, grpo_rasp should outperform sft_rasp on MATH-500. If not, reinforces C1.\", \"notes\": \"失败原因: EXIT_CODE=124 timeout (~6h)。GRPO RASP 模型生成极长推理链 (~112s/problem vs SFT ~25s)，仅完成 193/500 题。| 已有成果: 前 150 题 partial acc = 30.67% | 建议: D051 已裁定 MATH-500 GRPO 对比不可用于 C3 论证（配置不公平），不建议重跑。partial data 可作为 supplementary evidence 记录 GRPO 生成行为变化。| v1 (eval_math500_grpo_rasp_20) 同样失败。\", \"parent\": \"eval_math500_grpo_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T14:59:30.795Z\"}, \"eval_sft_cka_only_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T14:28:35.380Z\", \"hypothesis\": \"CKA-only 20% post-SFT GSM8K accuracy (N=200). Post-prune was 38.5% (highest among all methods). If post-SFT >> 60%, CKA-only scoring is superior for SFT recovery. If ~60% like RASP/Standard/Random, confirms SFT equalizes all scoring methods regardless of post-prune advantage.\", \"metrics\": {\"avg_response_length\": 182.73, \"eos_rate\": 0.995, \"gsm8k_accuracy\": 0.64, \"gsm8k_stderr\": 0.0339, \"mode\": \"greedy\", \"n_correct\": 128, \"n_total\": 200, \"seed\": 42, \"truncated\": 1}, \"parent\": \"sft_cka_only_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T14:48:17.267Z\"}, \"eval_humaneval_sft_standard_20_2048\": {\"created_at\": \"2026-05-17T13:53:51.297Z\", \"hypothesis\": \"HumanEval pass@1 for SFT Standard 20% with max_new_tokens=2048. Completes 5-way HumanEval@2048 matrix. Compares SFT Standard vs SFT RASP (10.37%) code generation after recovery. Queued for westd cuda:2 after GRPO Standard 2048 completes.\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T14:41:27.370Z\"}, \"sft_cka_only_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T13:43:50.320Z\", \"hypothesis\": \"CKA-only scoring 20% post-SFT accuracy. Post-prune accuracy was 38.5% (N=200), higher than RASP 29% and Random 34%. If post-SFT converges to ~60% like other methods, confirms SFT equalizes different pruning strategies. If significantly higher, CKA-only might be superior scoring for SFT recovery.\", \"metrics\": {\"checkpoint_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20/\", \"note\": \"Initial loss 1.958 > RASP 1.86 > Standard 1.70 (CKA-only has most initial damage). Final loss 0.62 comparable to baselines. No greedy eval run yet.\", \"token_accuracy\": 0.8362, \"total_steps\": 1870, \"train_loss_final\": 0.6165, \"train_loss_initial\": 1.958, \"train_time_min\": 33.4}, \"parent\": \"scoring_ablation_cka_only_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T14:28:29.688Z\"}, \"eval_humaneval_unpruned_2048\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T12:40:50.255Z\", \"hypothesis\": \"HumanEval pass@1 for unpruned DeepSeek-R1-Distill-Qwen-7B with max_new_tokens=2048 (previous run used 512 which truncated thinking chain). Establishes dense model ceiling for code generation comparison.\", \"metrics\": {\"avg_response_length\": 1771, \"correct\": 74, \"max_new_tokens\": 2048, \"median_response_length\": 2048, \"pass_at_1\": 0.4512, \"stderr\": 0.0389, \"total\": 164, \"wall_time_min\": 67.6}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T13:53:59.636Z\"}, \"eval_humaneval_sft_rasp_20_2048\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T12:40:51.686Z\", \"hypothesis\": \"HumanEval pass@1 for SFT RASP 20% with max_new_tokens=2048 (previous run used 512 which truncated thinking chain). Tests whether longer generation improves code quality for pruned+recovered model.\", \"metrics\": {\"correct\": 17, \"max_new_tokens\": 2048, \"median_response_length\": 2048, \"note\": \"still truncating at median=2048, main failure mode is thinking chain leaking into code output\", \"pass_at_1\": 0.1037, \"stderr\": 0.0238, \"total\": 164, \"wall_time_min\": 42}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T13:42:41.560Z\"}, \"eval_humaneval_grpo_standard_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T10:00:40.683Z\", \"hypothesis\": \"HumanEval pass@1 for grpo_standard_20 vs sft_standard_20 (3.05%). If grpo_standard >> sft_standard on HumanEval, GRPO transfers code generation ability even with Standard pruning. Completes HumanEval comparison matrix.\", \"metrics\": {\"correct\": 3, \"max_new_tokens\": 512, \"note\": \"512-token truncation, low quality\", \"pass_at_1\": 0.0183, \"total\": 164}, \"parent\": \"eval_humaneval_sft_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T13:33:59.897Z\"}, \"eval_math500_unpruned\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T06:23:49.923Z\", \"hypothesis\": \"MATH-500 baseline: unpruned DeepSeek-R1-Distill-Qwen-7B accuracy on MATH-500. Establishes dense model ceiling for cross-benchmark generalization comparison with pruned+recovered models.\", \"metrics\": {\"N\": 500, \"accuracy\": 0.736, \"correct\": 368, \"stderr\": 0.02}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T12:40:26.343Z\"}, \"eval_gradient_postsft\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T10:07:58.644Z\", \"hypothesis\": \"GSM8K accuracy after SFT recovery on gradient-pruned model. Pre-SFT was 25.5%. If post-SFT reaches ~50-60%, gradient scoring is viable but weaker than RASP (~61%). If much lower, gradient scoring causes partially irreversible damage.\", \"metrics\": {\"accuracy\": 0.615, \"avg_response_length\": 167.455, \"correct\": 123, \"eos_rate\": 0.995, \"stderr\": 0.0344, \"total\": 200}, \"parent\": \"gradient_sft_v3\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T11:24:16.260Z\"}, \"scoring_ablation_batch_v2\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T05:45:47.123Z\", \"hypothesis\": \"Scoring ablation with controlled search space (MLP-only, --skip_attention): CKA-aware scoring (RASP) preserves more post-prune accuracy than magnitude-only, gradient-only, random, or CKA-only scoring at 20% sparsity. Search space restricted to MLP groups only (matching RASP/Standard natural behavior of 0/112 attention groups pruned) for fair comparison.\", \"metrics\": {\"gradient_postprune\": {\"acc\": 0.255, \"n_samples\": 200, \"note\": \"25.5% - significantly better than magnitude (0%), gradient preserves some structure\"}, \"gradient_sft\": {\"disk_issue\": \"/dev/md0 250G 100% full\", \"reason\": \"Disk full at step 935/1870 (50%)\", \"status\": \"FAILED\"}, \"magnitude_postprune\": {\"acc\": 0, \"avg_len\": 4054, \"early_stopped\": true, \"eos_rate\": 0.02, \"n_samples\": 60}, \"magnitude_sft\": {\"reason\": \"Extreme per-layer non-uniformity, unrecoverable\", \"status\": \"FAILED\"}, \"random_postprune\": {\"progress\": \"26/200\", \"status\": \"in_progress\"}}, \"notes\": \"失败原因: westb-23072 /dev/md0 (250G系统盘) 在 gradient_sft step 935/1870 时写满 | 已有成果: magnitude_postprune=0%(60样本,early_stop), magnitude_sft=FAILED(non-uniformity不可恢复), gradient_postprune=25.5%(200样本), random_postprune 仅完成 26/200 | gradient_sft 已由独立实验 gradient_sft_v3 成功完成 | 建议: 清理系统盘后重试，或拆分为独立实验分别跑(scoring_ablation_magnitude_20, scoring_ablation_random_20, scoring_ablation_cka_only_20 已在 PREPARING)\", \"parent\": \"scoring_ablation_batch\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T10:23:53.103Z\"}, \"eval_gradient_postsft_v2\": {\"created_at\": \"2026-05-17T10:14:25.361Z\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T10:14:25.361Z\"}, \"gradient_sft_v3\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T09:28:21.646Z\", \"hypothesis\": \"SFT recovery on gradient-pruned model (25.5% post-prune acc). If SFT recovers gradient to ~50-60%, gradient scoring is viable but weaker than CKA-aware. If recovery fails or minimal, gradient scoring causes irreversible damage similar to magnitude.\", \"metrics\": {\"epochs\": 2, \"final_loss\": 0.644, \"output_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_gradient_20\", \"steps\": 1870, \"token_accuracy\": 0.825}, \"parent\": \"scoring_ablation_batch_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T10:08:07.026Z\"}, \"eval_math500_sft_standard_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T06:23:54.283Z\", \"hypothesis\": \"MATH-500 eval for Standard 20% post-SFT model. Comparison point: does Standard pruning preserve MATH-500 capability similarly to its GSM8K performance (64%)? Part of Plan_012 extended eval.\", \"metrics\": {\"correct\": 130, \"eos_rate\": 0.578, \"math500_acc\": 0.26, \"stderr\": 0.0196, \"total\": 500, \"truncated\": 211, \"wall_time_hours\": 3.58}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T10:00:26.439Z\"}, \"eval_math500_sft_rasp_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T06:23:52.474Z\", \"hypothesis\": \"MATH-500 eval for RASP 20% post-SFT model. Tests whether RASP pruning+recovery generalizes beyond GSM8K to harder math reasoning (MATH-500). Part of Plan_012 extended eval.\", \"metrics\": {\"correct\": 121, \"math500_acc\": 0.242, \"stderr\": 0.0192, \"total\": 500, \"wall_time_hours\": 2.94}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T09:24:16.959Z\"}, \"eval_unstructured_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T05:35:41.205Z\", \"hypothesis\": \"Unstructured magnitude pruning at 20% sparsity should retain more accuracy than structured pruning (RASP/Standard) at same sparsity level, since unstructured preserves model architecture. Serves as calibration baseline for structured vs unstructured gap. Expected post-prune accuracy ~75-80% (mild degradation from 82% dense).\", \"metrics\": {\"avg_response_length\": 641, \"correct\": 1159, \"eos_rate\": 0.9803, \"gsm8k_acc\": 0.8787, \"stderr\": 0.009, \"total\": 1319, \"truncated\": 26, \"wall_time_hours\": 3.23}, \"parent\": \"prune_unstructured_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T08:50:18.688Z\"}, \"eval_math500_grpo_rasp_20\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T08:32:03.101Z\", \"hypothesis\": \"MATH-500 accuracy for grpo_rasp_20 vs sft_rasp_20. If GRPO adds math reasoning beyond SFT recovery, grpo_rasp should outperform sft_rasp on MATH-500. If not, reinforces C1 (GRPO reward improves but harder math accuracy doesn't follow).\", \"parent\": \"eval_math500_sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T08:34:21.781Z\"}, \"eval_humaneval_sft_standard_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T07:56:08.222Z\", \"hypothesis\": \"HumanEval pass@1 for sft_standard_20 compared to sft_rasp_20 (7.32%) and grpo_rasp_20 (10.37%). If sft_standard ≈ sft_rasp → pruning method doesn't affect code generation recovery. If sft_standard << sft_rasp → RASP pruning preserves more code-relevant structure.\", \"metrics\": {\"correct\": 5, \"failure_modes\": \"model generates CoT natural language instead of code, all responses truncated at max_tokens=512\", \"pass_at_1\": 0.0305, \"stderr\": 0.0134, \"total\": 164, \"wall_time_min\": 17}, \"parent\": \"eval_humaneval_sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T08:31:52.684Z\"}, \"eval_humaneval_sft_rasp_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T07:19:22.820Z\", \"hypothesis\": \"If SFT (without GRPO) already produces ~10% HumanEval pass@1 on pruned model, then GRPO adds no HumanEval increment, confirming C1 decoupling (reward improves but code generation ability comes from SFT instruction-following, not GRPO)\", \"metrics\": {\"correct\": 12, \"failure_modes\": \"model outputs natural language thinking instead of code (SyntaxError), parenthesis mismatch\", \"median_response_length\": 512, \"note\": \"max_tokens truncation frequent\", \"pass_at_1\": 0.0732, \"stderr\": 0.0203, \"total\": 164}, \"parent\": \"eval_humaneval_grpo_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T07:55:52.564Z\"}, \"multiseed_serial_westb\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T05:47:08.060Z\", \"hypothesis\": \"Multi-seed variance estimation (westb fallback): 4 serial evals (RASP×2 + Standard×2, seeds 123/456, N=200) to complement seed=42 data. Transferred from failed westd-11672. Results needed for 5-seed statistical significance in Paper Table 1.\", \"metrics\": {\"missing\": \"seed 42 and seed 789 not executed\", \"note\": \"2 seeds x 2 methods (not 4 seeds as planned). Script ran RASP+Standard for seeds 123,456.\", \"rasp_seed123\": {\"acc\": 0.605, \"correct\": 121, \"total\": 200}, \"rasp_seed456\": {\"acc\": 0.6, \"correct\": 120, \"total\": 200}, \"standard_seed123\": {\"acc\": 0.645, \"correct\": 129, \"total\": 200}, \"standard_seed456\": {\"acc\": 0.61, \"correct\": 122, \"total\": 200}}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T07:50:11.807Z\"}, \"eval_humaneval_grpo_rasp_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T06:42:19.044Z\", \"hypothesis\": \"HumanEval eval for RASP 20% post-GRPO model. Verifies C1 on code generation: post-GRPO accuracy should ≈ post-SFT (GRPO doesn't improve non-GSM8K tasks on pruned models). Baseline unpruned = 1.83% pass@1.\", \"metrics\": {\"n_passed\": 17, \"n_total\": 164, \"pass_at_1\": 0.1037, \"stderr\": 0.0238}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T07:15:58.856Z\"}, \"eval_humaneval_unpruned\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T06:23:55.527Z\", \"hypothesis\": \"HumanEval baseline: unpruned DeepSeek-R1-Distill-Qwen-7B pass@1 on HumanEval (164 problems). Establishes dense model ceiling for code generation capability comparison.\", \"metrics\": {\"n_passed\": 3, \"n_total\": 164, \"pass_at_1\": 0.0183, \"stderr\": 0.0105}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T06:42:38.578Z\"}, \"eval_sft_standard_20_seed456\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T03:18:19.145Z\", \"hypothesis\": \"Multi-seed variance estimation: Standard 20% post-SFT GSM8K accuracy should show low variance (std<3pp) across seeds, confirming seed=42 result (64%) is representative. Part of 5-seed suite for statistical significance.\", \"notes\": \"westd-11672 服务器不可达 (SSH check failed 5x, Unable to connect to port 11672). 非代码问题，服务器恢复后需重跑。轻量 eval 任务 (n=200)。\", \"parent\": \"sft_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T05:44:27.075Z\"}, \"eval_sft_rasp_20_seed456\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T03:18:18.631Z\", \"hypothesis\": \"Multi-seed variance estimation: RASP 20% post-SFT GSM8K accuracy should show low variance (std<3pp) across seeds, confirming seed=42 result (57%) is representative. Part of 5-seed suite for statistical significance.\", \"notes\": \"westd-11672 服务器不可达 (SSH check failed 5x, Unable to connect to port 11672). 非代码问题，服务器恢复后需重跑。轻量 eval 任务 (n=200)。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T05:43:40.502Z\"}, \"eval_sft_standard_20_seed123\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T03:18:18.061Z\", \"hypothesis\": \"Multi-seed variance estimation: Standard 20% post-SFT GSM8K accuracy should show low variance (std<3pp) across seeds, confirming seed=42 result (64%) is representative. Part of 5-seed suite for statistical significance.\", \"notes\": \"westd-11672 服务器不可达 (SSH check failed 5x, Unable to connect to port 11672). 非代码问题，服务器恢复后需重跑。轻量 eval 任务 (n=200)。\", \"parent\": \"sft_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T05:43:39.380Z\"}, \"eval_sft_rasp_20_seed123\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T03:18:16.149Z\", \"hypothesis\": \"Multi-seed variance estimation: RASP 20% post-SFT GSM8K accuracy should show low variance (std<3pp) across seeds, confirming seed=42 result (57%) is representative. Part of 5-seed suite for statistical significance.\", \"notes\": \"westd-11672 服务器不可达 (SSH check failed 5x, Unable to connect to port 11672). 非代码问题，服务器恢复后需重跑。轻量 eval 任务 (n=200)。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T05:43:38.035Z\"}, \"scoring_ablation_batch\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-17T04:49:20.963Z\", \"hypothesis\": \"Scoring ablation: CKA-aware scoring (RASP) preserves more post-prune accuracy than magnitude-only, gradient-only, random, or CKA-only scoring at 20% sparsity. Isolates CKA's contribution to the composite RASP score S(h)=I(h)×(1-F(h))^α.\", \"notes\": \"Killed: Director 要求加 --skip_attention 参数重跑。旧版本搜索空间包含 attention groups 不公平（RASP/Standard 自然不剪 attention），需控制变量。替代: scoring_ablation_batch_v2\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T05:40:11.318Z\"}, \"eval_grpo_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T20:04:16.057Z\", \"hypothesis\": \"DeepSeek-R1-Distill-Qwen-7B RASP 25% post-GRPO GSM8K eval (N=1319, greedy, seed=42). GRPO frac_zero=0.875 (severe collapse), reward=0.009. C1 25% ��键验证：collapse 后 accuracy 是否 ≈ pre-GRPO (52.99%)。Parent: grpo_rasp_25.\", \"metrics\": {\"accuracy\": 0.5315, \"avg_len\": 433.85, \"eos_rate\": 0.9272, \"max_len\": 4096, \"min_len\": 39, \"n_correct\": 701, \"n_total\": 1319, \"stderr\": 0.0137, \"truncated\": 96}, \"parent\": \"grpo_rasp_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T05:27:33.072Z\"}, \"eval_grpo_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T19:39:31.510Z\", \"hypothesis\": \"DeepSeek-R1-Distill-Qwen-7B Standard 25% post-GRPO GSM8K eval (N=1319, greedy, seed=42). GRPO reward=0.0075(near-collapse)，验证 accuracy 损失程度。对比 pre-GRPO sft_standard_25: 51.25%. Parent: grpo_standard_25.\", \"metrics\": {\"accuracy\": 0.511, \"avg_len\": 292.86, \"eos_rate\": 0.9628, \"n_correct\": 674, \"n_total\": 1319, \"stderr\": 0.01376}, \"notes\": \"Registry 被 cron 误标 DONE(failed)。实际 PID 48540 仍在运行（SSH 确认 2026-05-17T02:00: 1205/1319=91.4%, acc=51.17%, eos=96.5%）。预计 5-10 min 后完成。结果写入 /root/autodl-tmp/recovery_aware_struct_prune/results/eval_grpo_standard_25_n1319.json。完成后需手动收割。\", \"parent\": \"grpo_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T04:49:07.062Z\"}, \"prune_unstructured_20\": {\"created_at\": \"2026-05-17T04:21:55.112Z\", \"hypothesis\": \"Global magnitude unstructured pruning at 20% sparsity. Structured pruning (RASP/Standard) 应该在 recovery 上优于 unstructured，因为保留完整 attention heads 维持了推理链路的结构完整性。预期 unstructured post-prune accuracy 高于 structured (no head removal) 但 post-SFT recovery gap 更大.\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T04:21:55.112Z\"}, \"eval_extended_math500_rasp_sft\": {\"created_at\": \"2026-05-17T04:21:51.903Z\", \"hypothesis\": \"RASP 20% post-SFT MATH-500 eval. C1 验证: GSM8K 上观察到的 reward-accuracy decoupling 在 MATH-500 上同样成立 (post-GRPO ≈ post-SFT accuracy). 同时验证 SFT 恢复的泛化性 (不只是 GSM8K pattern memorization).\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T04:21:51.903Z\"}, \"scoring_ablation_cka_only_20\": {\"created_at\": \"2026-05-17T04:21:48.906Z\", \"hypothesis\": \"CKA-only scoring (remove highest functional overlap first) at 20% sparsity. Tests whether CKA alone (without importance weighting) is a valid pruning criterion. If worse than RASP but better than random, confirms importance×CKA interaction is key.\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T04:21:48.906Z\"}, \"scoring_ablation_random_20\": {\"created_at\": \"2026-05-17T04:21:46.255Z\", \"hypothesis\": \"Random scoring at 20% sparsity (seed=42). Lower bound baseline — any principled scoring should beat random by significant margin. Expected post-prune accuracy near 0% (like 35% sparsity results), post-SFT should recover but less than all structured methods.\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T04:21:46.256Z\"}, \"scoring_ablation_gradient_20\": {\"created_at\": \"2026-05-17T04:21:43.502Z\", \"hypothesis\": \"Gradient-only scoring (Taylor importance per group) at 20% sparsity. Equivalent to Standard method. Baseline for CKA contribution measurement — difference between this and RASP isolates CKA's additive value.\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T04:21:43.502Z\"}, \"grpo_standard_qwen_math_v3\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-16T14:49:42.896Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% GRPO v3 (100 steps, save_steps=100). 跨模型验证 C2: Standard collapse gradient. 修复 save_steps=5 磁盘膨胀问题。Parent: sft_qwen_math_standard_20.\", \"metrics\": {\"clipped_ratio_final\": 0.856, \"collapse_onset\": \"step1\", \"collapse_pattern\": \"persistent_reward_homogeneity\", \"cross_model_match\": false, \"entropy_mean\": 0.187, \"frac_zero_std_final\": 0.85, \"frac_zero_std_max\": 0.9, \"frac_zero_std_min\": 0.75, \"grad_norm_max\": 172, \"kl_final\": 0.005, \"llama_pattern\": \"transient_dip_recovery\", \"recovery\": false, \"reward_final\": 0.044, \"reward_min\": 0.031, \"reward_peak\": 0.069, \"reward_std_final\": 0.1458, \"total_steps\": 100}, \"notes\": \"Cross-model C2 validation FAILED. Llama Standard showed transient dip (step60) + recovery (step90); Qwen Standard shows persistent high frac_zero_std (0.75-0.90) from step 1 with NO clear recovery arc. Reward flat 0.03-0.07. Entropy healthy (~0.18). Two grad_norm spikes (step60: 172, step80: 130) but no sustained improvement. The collapse mechanism differs: Llama had reward dynamics; Qwen has reward-signal starvation. Pattern is \\\"persistent reward-homogeneity\\\" not \\\"transient dip+recovery\\\".\", \"parent\": \"sft_qwen_math_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:34:38.064Z\", \"wandb_run_id\": \"5n2snh48\"}, \"grpo_rasp_25_qwen_math\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-16T12:51:11.170Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 25% GRPO (100 steps, save_steps=5). 跨模型×跨稀疏度验证 C2: RASP collapse pattern. 对比 20% (grpo_rasp_qwen_math) 和 Standard 25% (grpo_standard_25_qwen_math)。Parent: sft_qwen_math_rasp_25.\", \"metrics\": {\"clipped_ratio_final\": 0.719, \"collapse_onset\": \"none\", \"collapse_pattern\": \"no_collapse\", \"comparison_vs_20pct\": \"25pct_better_than_20pct\", \"completion_length_final\": 811.9, \"entropy_final\": 0.09, \"frac_0std_improvement_vs_20pct\": \"0.675->0.350\", \"frac_zero_std_final\": 0.35, \"frac_zero_std_max\": 0.575, \"frac_zero_std_min\": 0.25, \"frac_zero_std_trend\": \"improving\", \"kl_final\": 0.003789, \"kl_spike_recovery\": \"immediate_step70\", \"kl_spike_step60\": 725.1, \"loss_final\": 0.06824, \"max_steps_reached\": true, \"recovery\": \"n/a\", \"reward_final\": 0.2056, \"reward_min\": 0.111, \"reward_peak\": 0.225, \"reward_ratio_vs_20pct\": 3.4, \"reward_std_final\": 0.4003, \"total_steps\": 100}, \"notes\": \"NEGATIVE for sparsity gradient hypothesis: 25% RASP shows NO collapse (frac_zero_std 0.25-0.575, reward 0.11-0.23), dramatically better than 20% RASP (frac_zero_std 0.55-0.70, reward 0.05-0.10). One transient KL spike at step 60 (725) with immediate recovery. Higher sparsity paradoxically produces better GRPO outcomes. Contradicts C3 (more sparsity → worse collapse). See artifacts/analysis_grpo_qwen_math_25.md.\", \"parent\": \"sft_qwen_math_rasp_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:34:37.514Z\", \"wandb_run_id\": \"3vjjzi13\"}, \"grpo_standard_25_qwen_math\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-16T12:51:12.657Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 25% GRPO (100 steps, save_steps=5). 跨模型×跨稀疏度验证 C2: Standard collapse gradient. 对比 20% (grpo_standard_qwen_math) 和 RASP 25% (grpo_rasp_25_qwen_math)。Parent: sft_qwen_math_standard_25.\", \"metrics\": {\"clipped_ratio_final\": 0.338, \"collapse_onset\": \"step20_first_kl_spike\", \"collapse_pattern\": \"kl_explosion_transient_no_reward_collapse\", \"comparison_vs_20pct\": \"25pct_better_than_20pct\", \"completion_length_final\": 527, \"entropy_final\": 0.238, \"frac_0std_improvement_vs_20pct\": \"0.850->0.325\", \"frac_zero_std_final\": 0.325, \"frac_zero_std_max\": 0.425, \"frac_zero_std_min\": 0.225, \"frac_zero_std_trend\": \"improving\", \"kl_final\": 0.2983, \"kl_spike_count\": 3, \"kl_spike_recovery\": \"always_within_10_steps\", \"kl_spike_step20\": 56.08, \"kl_spike_step40\": 7913000000000000, \"kl_spike_step80\": 4096000, \"loss_final\": 0.1651, \"loss_spike_step40\": 369500000000000, \"loss_spike_step80\": 220300, \"max_steps_reached\": true, \"recovery\": true, \"reward_final\": 0.1819, \"reward_min\": 0.106, \"reward_peak\": 0.211, \"reward_ratio_vs_20pct\": 4.1, \"reward_std_final\": 0.3673, \"total_steps\": 100}, \"notes\": \"NEGATIVE for sparsity gradient: 25% Standard shows NO reward collapse (frac_zero_std 0.225-0.425, reward 0.11-0.21) vs 20% Standard permanent collapse (frac_zero_std 0.75-0.90, reward 0.03-0.07). New failure mode: 3 catastrophic KL explosions (steps 20/40/80, peak 7.9e15) with self-recovery each time — DAPO clipping prevents reward collapse despite astronomical KL divergence. Contradicts C3. See artifacts/analysis_grpo_qwen_math_25.md.\", \"parent\": \"sft_qwen_math_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:34:36.509Z\", \"wandb_run_id\": \"16vqw4e6\"}, \"eval_grpo_standard_step50_full\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-15T22:07:43.463Z\", \"hypothesis\": \"D043 plan_004 (Claim 1): Standard GRPO v8 step-50 checkpoint GSM8K eval (N=1319, greedy, seed=42). Step 50 是 GRPO peak 前最后可用 checkpoint (step 40 peak reward 0.096, step 60 collapse)。量化 GRPO recovery 的最高水平。Parent: grpo_stage2_standard_20_v8.\", \"metrics\": {\"accuracy\": 0.5891, \"avg_len\": 222.1, \"eos_rate\": 0.981, \"grpo_delta_pp\": -0.38, \"max_response_length\": 4096, \"min_response_length\": 32, \"n_correct\": 777, \"n_total\": 1319, \"natural_eos\": 1294, \"sft_baseline_accuracy\": 0.5929, \"stderr\": 0.0135, \"truncated\": 25}, \"parent\": \"grpo_stage2_standard_20_v8\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:34:35.470Z\"}, \"eval_postprune_standard_25\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-16T08:12:16.403Z\", \"hypothesis\": \"25% Standard post-prune GSM8K eval (N=100, greedy). 对比 20% post-prune (27%) 和 RASP 25% (21%). Parent: pruned_standard_25.\", \"metrics\": {\"accuracy\": 0.16, \"n_total\": 100, \"note\": \"Standard 25% post-prune 16% vs RASP 25% post-prune 21%. Standard worse as expected.\"}, \"parent\": \"pruned_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:34:34.548Z\"}, \"sft_standard_20_retrain\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T08:00:22.779Z\", \"hypothesis\": \"Standard 20% SFT retrain with identical hyperparameters reproduces original loss/accuracy, confirming SFT recovery is deterministic and prior result was not anomalous\", \"metrics\": {\"conclusion\": \"Matches original sft_standard_20 (loss 0.64, token_accuracy 83%). Retrain successful.\", \"token_accuracy\": 0.83, \"train_loss_final\": 0.64}, \"notes\": \"SFT Standard retrain 完成. loss 0.64, token_accuracy 83%, 与原始 sft_standard_20 完全一致. Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20/. 用于 Standard GRPO v5 对照实验.\", \"parent\": \"prune_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:39.616Z\"}, \"eval_sft_grasp_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T15:45:15.051Z\", \"hypothesis\": \"GraSP 20% post-SFT achieves significantly lower accuracy than Standard and RASP, showing gradient-signal pruning damages SFT-recovery capacity more than magnitude-based methods\", \"metrics\": {\"accuracy\": 0.41, \"n_total\": 100, \"note\": \"论文核心数据点: GraSP post-SFT 41% vs Standard 64% (p=0.001) vs RASP 57%\", \"p_value_vs_standard\": 0.001, \"rasp_ref\": 0.57, \"standard_ref\": 0.64}, \"notes\": \"GraSP post-SFT eval 完成: 41% accuracy (N=100, greedy, seed=42). 论文核心数据点。三方对比: Standard 64% > RASP 57% > GraSP 41% (p=0.001 vs Standard). GraSP post-prune ~6% → post-SFT 41% (+35pp recovery), 但仍远低于 RASP/Standard. JSON: results/eval_sft_grasp_20_n100.json\", \"parent\": \"sft_grasp_20_westd\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T03:29:38.882Z\"}, \"eval-sft-alpha-0p0\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T14:26:31.883Z\", \"hypothesis\": \"Alpha=0.0 (no CKA, pure magnitude) post-SFT matches Standard pruning recovery (~64%), establishing that removing CKA collapses RASP to standard behavior (C2 ablation endpoint)\", \"metrics\": {\"accuracy\": 0.64, \"avg_len\": 257.9, \"eos_rate\": 0.97, \"n_correct\": 64, \"n_total\": 100}, \"parent\": \"sft-alpha-0p0\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:37.940Z\"}, \"eval-sft-alpha-1p0\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T14:51:22.694Z\", \"hypothesis\": \"Alpha=1.0 (full CKA weight) post-SFT accuracy matches RASP default (~57%), confirming alpha=1.0 produces identical pruning structure to standard RASP (C2 ablation endpoint)\", \"metrics\": {\"accuracy\": 0.57, \"avg_len\": 224.18, \"eos_rate\": 0.98, \"n_correct\": 57, \"n_total\": 100, \"natural_eos\": 98, \"stderr\": 0.0495, \"truncated\": 2}, \"notes\": \"α=1.0 SFT eval (N=100, greedy) 运行中。PID 42535 on GPU 1 (westd). 33/100 samples at 15:05 UTC, ~4-5s/sample, 预计 5-6 min 完成。Cron 已注册。\", \"parent\": \"sft-alpha-1p0\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:36.910Z\"}, \"eval_sft_unpruned_n100\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T01:40:17.686Z\", \"hypothesis\": \"Unpruned post-SFT achieves ~84% GSM8K on N=100 subset, providing quick baseline confirmation consistent with full eval for three-way pruning method comparison\", \"metrics\": {\"accuracy\": 0.84, \"avg_response_length\": 187.22, \"eos_rate\": 1, \"n_correct\": 84, \"n_total\": 100, \"stderr\": 0.0367}, \"parent\": \"sft_unpruned_baseline\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:35.970Z\"}, \"eval_sft_unpruned_full\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T01:40:17.174Z\", \"hypothesis\": \"Unpruned post-SFT achieves >80% GSM8K on full test set (N=1319), establishing accuracy ceiling for pruned model SFT recovery comparison and confirming SFT effectiveness intact (C1/C3 control)\", \"metrics\": {\"accuracy\": 81.27, \"accuracy_ci\": 1.07, \"avg_response_length\": 207.18, \"correct\": 1072, \"eos_rate\": 99.7, \"total\": 1319, \"truncated\": 4}, \"notes\": \"Unpruned SFT N=1319 full eval on westd cuda:0. PID 74129, ~2.5s/it. Started 09:39 UTC. Progress at 09:46 UTC: 155/1319 (12%), acc=86.67% (at 150), eos_rate=100%, avg_len=188. ETA ~10:35 UTC. Model: /root/autodl-tmp/recovery_aware_struct_prune/sft_unpruned_baseline. N=100 checkpoint: 84% (84/100). Three-way comparison pending: Standard 59.29%, RASP 61.49%, Unpruned ?%.\", \"parent\": \"sft_unpruned_baseline\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:35.056Z\"}, \"eval_grpo_unpruned_v2_step90\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T03:05:00.333Z\", \"hypothesis\": \"Unpruned model GRPO step-90 shows accuracy tracking reward throughout training, confirming reward-accuracy coupling is intact when no structural pruning damage exists (C1 control)\", \"metrics\": {\"accuracy\": 80.59, \"avg_response_length\": 213, \"correct\": 1063, \"eos_rate\": 99.6, \"seed\": 42, \"total\": 1319}, \"parent\": \"grpo_unpruned_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:34.226Z\"}, \"eval_grpo_unpruned_v2_step100\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T03:04:55.936Z\", \"hypothesis\": \"Unpruned model GRPO step-100 achieves >80% GSM8K accuracy, proving reward-accuracy coupling holds without structural damage and decoupling is pruning-specific (C1 control)\", \"metrics\": {\"accuracy\": 81.27, \"avg_response_length\": 209, \"correct\": 1072, \"eos_rate\": 99.7, \"seed\": 42, \"total\": 1319}, \"parent\": \"grpo_unpruned_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:33.203Z\"}, \"sft_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T05:26:38.517Z\", \"hypothesis\": \"RASP 25% pruned model recovers higher GSM8K accuracy post-SFT than Standard 25% because CKA-preserved functional redundancy enables more efficient gradient-based recovery (C3)\", \"metrics\": {\"runtime_seconds\": 1635, \"token_accuracy\": 0.8073, \"train_loss\": 0.8498}, \"parent\": \"prune_rasp_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:32.685Z\"}, \"sft_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T05:21:16.758Z\", \"hypothesis\": \"Standard 25% pruned DeepSeek-R1-Distill-Qwen-7B recovers partial accuracy via SFT but below RASP 25% because magnitude-only pruning destroys recovery-critical redundancy (C3)\", \"metrics\": {\"model_keys\": 339, \"model_params\": \"5.79B\", \"note\": \"optimizer.pt save failed (RuntimeError) but model.safetensors intact\", \"runtime_seconds\": 2130, \"total_steps\": 1870}, \"parent\": \"prune_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:22.232Z\"}, \"sft_standard_25_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T15:52:30.818Z\", \"hypothesis\": \"Standard 25% pruned DeepSeek-R1-Distill-Qwen-7B SFT recovery yields lower GSM8K accuracy than RASP 25% due to irreversible functional redundancy destruction (C3 25% extension)\", \"metrics\": {\"checkpoint_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_25/model.safetensors\", \"final_loss\": 0.8381, \"token_acc\": 0.8018}, \"parent\": \"prune_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:21.686Z\"}, \"eval_grpo_rasp_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T15:59:57.504Z\", \"hypothesis\": \"RASP 20% pruned Qwen Math post-GRPO shows accuracy plateau despite reward improvement, confirming C1 decoupling occurs regardless of pruning method on second model\", \"metrics\": {\"accuracy\": 0.725, \"n_samples\": 200, \"seed\": 42}, \"parent\": \"grpo_rasp_qwen_math_v3\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:20.851Z\"}, \"eval_grpo_standard_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T15:59:59.175Z\", \"hypothesis\": \"Standard 20% pruned Qwen Math post-GRPO shows accuracy plateau below unpruned despite reward improvement, confirming reward-accuracy decoupling is cross-model (C1)\", \"metrics\": {\"accuracy\": 0.705, \"n_samples\": 200, \"seed\": 42}, \"parent\": \"grpo_standard_qwen_math_v3\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:19.801Z\"}, \"eval_grpo_rasp_25_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T15:59:53.951Z\", \"hypothesis\": \"RASP 25% pruned Qwen Math post-GRPO shows reward-accuracy decoupling on GSM8K, confirming C1 generalizes to higher sparsity on second model family\", \"metrics\": {\"accuracy\": 0.625, \"n_samples\": 200, \"seed\": 42}, \"parent\": \"grpo_rasp_25_qwen_math\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:18.878Z\"}, \"eval_pass_k8_unpruned_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T16:43:10.425Z\", \"hypothesis\": \"Unpruned Qwen Math post-GRPO achieves near-ceiling pass@8 on GSM8K, establishing that GRPO preserves solution diversity when no structural pruning damage exists (C1 control)\", \"metrics\": {\"accuracy\": 0.965, \"k\": 8, \"n_samples\": 200, \"pass_at_k\": 0.965, \"stderr\": 0.013, \"temperature\": 0.7}, \"parent\": \"grpo_unpruned_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:17.923Z\"}, \"eval_pass_k8_rasp_20_grpo_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T16:43:12.096Z\", \"hypothesis\": \"RASP 20% post-GRPO on Qwen Math shows pass@8 below unpruned baseline, indicating GRPO fails to recover full solution diversity on structurally pruned models (C1 diversity)\", \"metrics\": {\"accuracy\": 0.915, \"k\": 8, \"n_samples\": 200, \"pass_at_k\": 0.915, \"stderr\": 0.0197, \"temperature\": 0.7}, \"parent\": \"grpo_rasp_qwen_math_v3\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:16.961Z\"}, \"eval_sft_rasp_rlvr_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T18:16:58.087Z\", \"hypothesis\": \"RASP-RLVR 20% pruned Qwen Math post-SFT achieves higher GSM8K accuracy than standard 20% because RLVR-aware scoring preserves recovery-critical structures (C3 cross-model)\", \"metrics\": {\"accuracy\": 0.73, \"mode\": \"greedy\", \"n_correct\": 146, \"n_samples\": 200}, \"parent\": \"sft_rasp_rlvr_20_qwen_math\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T03:29:16.019Z\"}, \"eval_grpo_standard_25_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T15:59:55.747Z\", \"hypothesis\": \"Standard 25% pruned Qwen Math post-GRPO exhibits reward-accuracy decoupling on GSM8K, confirming C1 generalizes across sparsity levels on second model family\", \"metrics\": {\"accuracy\": 0.635, \"n_samples\": 200, \"seed\": 42}, \"parent\": \"grpo_standard_25_qwen_math\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:14.637Z\"}, \"eval_pass_k8_rasp_20_sft_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T16:43:11.344Z\", \"hypothesis\": \"RASP 20% pruned Qwen Math post-SFT maintains high pass@8 near unpruned level because preserved functional redundancy supports multiple diverse reasoning paths (C1 diversity)\", \"metrics\": {\"avg_response_length\": 139.86, \"eos_rate\": 0.99625, \"k\": 8, \"n_problems\": 200, \"natural_eos\": 1594, \"pass_at_k\": 0.935, \"stderr\": 0.0174, \"temperature\": 0.7, \"truncated\": 6}, \"parent\": \"sft_rasp_20_qwen_math\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:13.689Z\"}, \"sft-alpha-1p0\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T13:53:32.178Z\", \"hypothesis\": \"SFT on alpha=1.0 pruned model (full CKA weight) recovers to level matching RASP default because alpha=1.0 IS the standard RASP scoring function (C2 ablation consistency)\", \"metrics\": {\"post_prune_accuracy\": 0.27, \"token_accuracy\": 0.83, \"total_steps\": 1870, \"train_loss_final\": 0.64, \"train_time_min\": 28}, \"notes\": \"α=1.0 SFT 完成 (1870/1870 steps, 2 epochs, ~28min). loss=0.64, token_acc=0.83. Post-prune 27% → post-SFT 需 eval 确认 (预期 ~57% 与 sft_rasp_20 一致，因 α=1.0 = RASP default). Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_ablation/alpha_1.0\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:28:07.214Z\"}, \"prune_rasp_30\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T09:03:45.925Z\", \"hypothesis\": \"RASP scoring at 30% sparsity maintains measurably higher post-prune accuracy than standard, testing whether CKA-preservation delays the structural collapse threshold\", \"metrics\": {\"actual_sparsity\": 0.2873, \"attn_groups_pruned\": \"0/112\", \"mlp_groups_pruned\": \"301/784\", \"model_size_gb\": 11, \"params_pruned\": 5427842560, \"target_sparsity\": 0.3}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:28:01.089Z\"}, \"prune_standard_30\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T09:06:31.546Z\", \"hypothesis\": \"Standard importance at 30% sparsity crosses structural collapse threshold where post-prune accuracy approaches zero, defining upper bound of viable pruning for DeepSeek-R1-Distill-Qwen-7B\", \"metrics\": {\"actual_sparsity\": 0.2854, \"attn_gqa_groups_pruned\": \"0/112\", \"mlp_groups_pruned\": \"299/784\", \"params_after\": 5442379264, \"target_sparsity\": 0.3}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:27:59.680Z\"}, \"prune_rasp_25_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T09:30:44.270Z\", \"hypothesis\": \"RASP CKA-weighted scoring at 25% on Qwen2.5-Math-7B preserves functionally redundant groups, maintaining higher post-prune accuracy than standard at same sparsity (C3 cross-model)\", \"metrics\": {\"actual_sparsity\": 0.2405, \"attn_gqa_groups_pruned\": \"0/112\", \"mlp_groups_pruned\": \"252/784\", \"params_after\": 5783991808, \"target_sparsity\": 0.25}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:27:58.263Z\"}, \"prune_standard_25_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T11:00:13.880Z\", \"hypothesis\": \"Standard importance at 25% on Qwen2.5-Math-7B removes groups by magnitude alone, destroying more functional redundancy than RASP at equal sparsity (C3 cross-model baseline)\", \"metrics\": {\"actual_sparsity\": 0.2396, \"attn_gqa_groups_pruned\": \"0/112\", \"mlp_groups_pruned\": \"251/784\", \"target_sparsity\": 0.25}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:27:56.876Z\"}, \"prune_rasp_rlvr_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T17:11:05.915Z\", \"hypothesis\": \"RASP-RLVR scoring on Qwen2.5-Math-7B at 20% sparsity preserves RLVR-relevant functional groups, yielding higher post-prune reasoning accuracy than standard importance (C3 cross-model)\", \"metrics\": {\"actual_sparsity\": 0.1909, \"attn_groups_pruned\": 0, \"attn_groups_total\": 112, \"mlp_groups_pruned\": 200, \"mlp_groups_total\": 784, \"pruned_params\": 6161946112}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:27:55.586Z\"}, \"eval_sft_standard_20_n1319_v2\": {\"created_at\": \"2026-05-17T03:18:09.035Z\", \"hypothesis\": \"Standard 20% post-SFT GSM8K full eval retry (N=1319, greedy, seed=42). 验证 westd 上 sft_standard_20 准确率是否一致 (~59.29% on westb). Retry of failed eval_sft_standard_20_n1319.\", \"parent\": \"sft_standard_20\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-17T03:19:18.590Z\"}, \"eval_pass_k8_rasp_20_grpo_deepseek\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T23:27:01.192Z\", \"hypothesis\": \"DeepSeek-R1-Distill-Qwen-7B RASP 20% post-GRPO pass@k=8 (N=200, T=0.7, seed=42). C1 diversity 验证：RASP collapse 模型的 sampling diversity。构建 pass@k 2×2 矩阵。Parent: grpo_stage2_rasp_20_v9.\", \"metrics\": {\"n_problems\": 200, \"pass_k8\": 0.89, \"temperature\": 0.7}, \"notes\": \"Cron auto-resolved as failed (5/5 miss on old PID 60022). 实际进程 PID 61473 仍在正常运行（已多次 SSH 确认，GPU 0 占用 12982MiB, 99% util, 进度 32% at 00:42 UTC）。参数已修正为 eval_pass_k.py + max_new_tokens=4096。等完成后手动收割结果更新 conclusion。\", \"parent\": \"grpo_stage2_rasp_20_v9\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:15:54.640Z\"}, \"inference_bench_full\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T01:55:16.783Z\", \"hypothesis\": \"Full inference benchmark: Dense vs RASP 20% vs Standard 20%. batch_size=[1,4,16], max_new_tokens=[128,512]. Measures wall-clock latency, tokens/s, peak memory across configs. RASP should maintain similar speedup ratio across batch sizes due to structural pruning.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T02:23:42.064Z\"}, \"eval_sft_alpha_0p5\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-15T15:44:06.901Z\", \"hypothesis\": \"α=0.5 post-SFT GSM8K eval (N=100, greedy). Post-prune 25%. Completes full α ablation: α=0.0 (64%), α=0.5 (?), α=1.0 (57%), α=2.0 (pending), α=4.0 (62%). Parent: alpha_ablation_westd_cal256.\", \"notes\": \"Director 决定跳过原始 α=0.5 eval。但 Worker 确认完整 alpha sweep 已完成（N=200, greedy, 20% sparsity）: α=0.0→70%, α=0.3→73%, α=0.5→74%, α=0.7→73.5%, α=1.0→75.5%, α=2.0→75.5%。结果路径: /root/autodl-tmp/recovery_aware_struct_prune/outputs/alpha_ablation/eval_alpha_*.json。趋势: α从0到1单调递增后饱和，最优α≈1.0-2.0。\", \"parent\": \"alpha_ablation_westd_cal256\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T02:21:40.166Z\"}, \"eval_pass_k8_standard_20_grpo_deepseek\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T23:31:55.162Z\", \"hypothesis\": \"DeepSeek-R1-Distill-Qwen-7B Standard 20% post-GRPO pass@k=8 (N=200, T=0.7, seed=42). C1 diversity 验证：Standard collapse 模型的 sampling diversity。完成 pass@k 2×2 矩阵。Parent: grpo_stage2_standard_20_v8.\", \"parent\": \"grpo_stage2_standard_20_v8\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T01:56:11.192Z\"}, \"eval_sft_rasp_20_full\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T16:21:29.964Z\", \"hypothesis\": \"RASP post-SFT full GSM8K eval (N=1319, greedy, seed=42). N=100 result: 57%. Full eval provides statistical significance for RASP vs Standard comparison. Parent: sft_rasp_20.\", \"metrics\": {\"accuracy\": 0.6156, \"avg_response_length\": 210.95, \"eos_rate\": 0.9841, \"n_correct\": 812, \"n_samples\": 1319, \"natural_eos\": 1298, \"stderr\": 0.0134, \"truncated\": 21}, \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T01:29:36.754Z\"}, \"eval_sft_standard_20_n1319\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-16T05:20:21.771Z\", \"hypothesis\": \"Standard post-SFT full GSM8K eval (N=1319, greedy, seed=42). N=100 result: 64%. Full eval provides tight CI for paper Table 1. Parent: sft_standard_20_retrain.\", \"metrics\": {\"accuracy\": 0.5929, \"do_sample\": false, \"eos_rate\": 0.9803, \"n_correct\": 782, \"n_samples\": 1319, \"stderr\": 0.01353, \"temperature\": 0}, \"parent\": \"sft_standard_20_retrain\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T01:23:00.666Z\"}, \"inference_speedup_plan016_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T21:56:34.646Z\", \"hypothesis\": \"Inference speedup benchmark v2 (code fix applied): Dense vs RASP 20% vs Standard 20%. 测量 wall-clock latency, tokens/s, memory_peak. 50 GSM8K prompts, batch_size=1, greedy, max_new_tokens=512. Parent: inference_speedup_plan016 (failed due to model loading bug, now fixed with load_pruned_model).\", \"metrics\": {\"dense\": {\"avg_latency_sec\": 6.682, \"peak_memory_gb\": 16.22, \"tokens_per_second\": 76.25}, \"rasp_20\": {\"avg_latency_sec\": 4.156, \"latency_speedup_vs_dense\": \"37.8%\", \"memory_reduction_vs_dense\": \"28.5%\", \"peak_memory_gb\": 11.6, \"tokens_per_second\": 52.07}, \"standard_20\": {\"avg_latency_sec\": 6.167, \"latency_speedup_vs_dense\": \"7.7%\", \"memory_reduction_vs_dense\": \"28.4%\", \"peak_memory_gb\": 11.61, \"tokens_per_second\": 49.78}}, \"parent\": \"inference_speedup_plan016\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T00:49:42.978Z\"}, \"eval_pass_k8_standard_20_grpo_qwen_math_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T21:54:25.214Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% post-GRPO pass@k=8 (N=200, T=0.7, seed=42). C1 diversity 对照：frac_zero=0.85 collapse 模型的 sampling diversity。重跑 v1（僵尸进程被 kill）。Parent: grpo_standard_qwen_math_v3.\", \"parent\": \"grpo_standard_qwen_math_v3\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T23:23:37.778Z\"}, \"inference_speedup_plan016\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-16T20:58:10.584Z\", \"hypothesis\": \"Inference speedup benchmark: Dense vs RASP 20% vs Standard 20%. 测量 wall-clock latency, tokens/s, memory_peak. 50 GSM8K prompts, batch_size=1, greedy, max_new_tokens=512. Plan_016.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T21:50:20.342Z\"}, \"grpo_rasp_rlvr_20\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-16T18:27:09.457Z\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T20:29:10.704Z\"}, \"eval_grpo_rasp_rlvr_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T19:39:30.069Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP-RLVR 20% post-GRPO GSM8K eval (N=200, greedy, seed=42). GRPO reward=0.090(最高)，验证 accuracy 是否也改善或依然 decoupling (C1)。对比 pre-GRPO: 73%. Parent: grpo_rasp_rlvr_20_qwen_math.\", \"metrics\": {\"accuracy\": 0.71, \"mode\": \"greedy\", \"n_samples\": 200, \"seed\": 42}, \"notes\": \"Cron 误判 (eval 无 W&B 信号)。实际成功完成。Post-GRPO accuracy 71.0% vs pre-GRPO SFT 73%: Δ=-2pp, 确认 C1 universal decoupling (reward=0.090 最高但 accuracy 不升反微降)。EOS=100%, avg_len=128, 生成行为正常。\", \"parent\": \"grpo_rasp_rlvr_20_qwen_math\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T20:25:58.464Z\"}, \"eval_pass_k8_standard_20_grpo_qwen_math\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-16T18:50:49.872Z\", \"hypothesis\": \"Standard 20% post-GRPO pass@k=8 (N=200, T=0.7). C1 diversity 对照：frac_zero=0.85 的更严重 collapse 模型是否仍保持 sampling diversity。Parent: grpo_standard_qwen_math_v3.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T20:18:34.175Z\"}, \"eval_postprune_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:07:02.187Z\", \"hypothesis\": \"25% RASP post-prune GSM8K eval (N=100, greedy). 对比 20% post-prune (31%). Parent: pruned_rasp_25.\", \"metrics\": {\"accuracy\": 21, \"avg_response_length\": 2032.9, \"correct\": 21, \"eos_rate\": 56, \"natural_eos\": 56, \"seed\": 42, \"stderr\": 4.07, \"total\": 100, \"truncated\": 44}, \"parent\": \"prune_rasp_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T20:09:54.911Z\"}, \"grpo_rasp_rlvr_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T19:37:40.324Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP-RLVR 20% post-GRPO (100 steps). RLVR 剪枝后 SFT→GRPO 全管线。对比 grpo_rasp_qwen_math_v3 (regular RASP, reward=0.061) 和 grpo_standard_qwen_math_v3 (Standard, reward=0.044)。D050 ablation: RLVR 是否在 Qwen Math 上提供额外 GRPO 恢复能力。Parent: sft_rasp_rlvr_20_qwen_math.\", \"metrics\": {\"clipped_ratio\": 0.54, \"comparison_vs_rasp_20\": \"RLVR reward 0.090 > RASP 0.061 (+48%), entropy 0.275 >> 0.073 (3.8x)\", \"comparison_vs_standard_20\": \"RLVR reward 0.090 >> Standard 0.044 (+105%)\", \"entropy_final\": 0.275, \"frac_zero_std_final\": 0.7, \"grad_norm_final\": 16.125, \"kl_final\": 0.00581, \"kl_spike_recovery\": \"immediate\", \"kl_spike_step70\": 5756.85, \"loss_final\": 0.0793, \"reward_final\": 0.09, \"reward_std_final\": 0.234, \"total_steps\": 100, \"wall_clock_min\": 45.8, \"wandb_run_id\": \"clzm2cy4\"}, \"parent\": \"sft_rasp_rlvr_20_qwen_math\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T20:02:41.614Z\"}, \"eval_sft_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T06:17:33.814Z\", \"hypothesis\": \"RASP 25% post-SFT GSM8K eval (N=1319, greedy, seed=42). sft_rasp_25 刚完成 (loss=0.8498, token_acc=0.8073)，对比 sft_standard_25 (待完成) 和 20% sparsity 结果 (RASP 57% vs Standard 64%)。Parent: sft_rasp_25.\", \"metrics\": {\"accuracy\": 0.5299, \"eos_rate\": 0.918, \"n_correct\": 699, \"n_samples\": 1319, \"seed\": 42, \"stderr\": 0.0137, \"truncated\": 108}, \"parent\": \"sft_rasp_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T19:15:43.879Z\"}, \"eval_sft_rasp_rlvr_20\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-16T14:51:38.892Z\", \"hypothesis\": \"RASP-RLVR 20% post-SFT GSM8K eval (N=1319, greedy, seed=42). 验证反向 CKA scoring 的 RLVR 恢复效果。对比 RASP SFT (61.49%) 和 Standard SFT (59.29%)。Parent: sft_rasp_rlvr_20.\", \"parent\": \"sft_rasp_rlvr_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T18:20:27.560Z\"}, \"sft_rasp_rlvr_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T17:11:51.076Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP-RLVR 20% SFT recovery (2 epochs). 验证反向 CKA 剪枝后的恢复质量。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T18:01:41.992Z\"}, \"grpo_rasp_qwen_math_v3\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T14:49:39.708Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% GRPO v3 (100 steps, save_steps=100). 跨模型验证 C1/C2. 修复 save_steps=5 磁盘膨胀问题。Parent: sft_qwen_math_rasp_20.\", \"metrics\": {\"clipped_ratio_final\": 0.975, \"clipped_ratio_mean\": 0.981, \"collapse_onset\": \"step1\", \"collapse_pattern\": \"entropy_length_collapse\", \"cross_model_match\": \"partial\", \"entropy_mean\": 0.073, \"entropy_vs_standard_ratio\": 0.39, \"frac_zero_std_final\": 0.675, \"frac_zero_std_max\": 0.7, \"frac_zero_std_min\": 0.55, \"kl_final\": 0.009, \"llama_pattern\": \"permanent_reward_collapse\", \"mean_completion_length\": 1010, \"recovery\": false, \"reward_final\": 0.061, \"reward_min\": 0.048, \"reward_peak\": 0.102, \"reward_std_final\": 0.2, \"total_steps\": 100}, \"notes\": \"Cross-model C1/C2 PARTIAL. Expected Llama-like reward collapse + frac_zero_std→0.95; instead got ENTROPY collapse (0.07 vs Standard's 0.18) + length pathology (clipped_ratio 0.97-1.0, mean_len ~1010). Reward actually functional (0.05-0.10), frac_zero_std moderate (0.55-0.70) — LOWER than Standard. Model can still solve problems but generates pathologically repetitive non-terminating outputs. Collapse IS permanent but mechanism completely different from Llama RASP. Interpretation: Qwen-Math-7B has enough capacity to maintain problem-solving under RASP damage; damage manifests as mode collapse in output space rather than inability. Paper should frame as \\\"pruning-method-dependent GRPO fragility\\\" not \\\"universal collapse signature\\\".\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T15:54:29.413Z\", \"wandb_run_id\": \"yyg9ty4u\"}, \"sft_rasp_rlvr_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T09:50:43.369Z\", \"hypothesis\": \"RASP-RLVR 20% post-prune SFT recovery (lr=2e-5, epochs=2). 验证反向 CKA scoring (保留冗余结构) 是否产生更好的 RLVR 恢复基础。对比 RASP SFT 和 Standard SFT。Parent: prune_rasp_rlvr_20.\", \"notes\": \"v1 failed (EXIT_CODE=2): wrong arg names. v2 fixed args but EXIT_CODE=1: 训练完成 2 epochs (1870 steps, 36min), loss ~0.64, token_acc ~0.83。模型 shards 已保存到 checkpoint-1870（6.16B params, 验证可加载，需用 load_pruned_model）。optimizer state 被截断（4.3G vs 预期 23G）不可恢复训练，但模型推理可用。westb 数据盘 250GB 100% 满，需清理 checkpoint-935 (35GB) 后才能跑新实验。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T14:50:02.686Z\"}, \"grpo_standard_qwen_math\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-16T08:42:44.572Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% GRPO (100 steps, save_steps=5). 跨模型验证 C2: Standard collapse gradient (transient dip+recovery). DeepSeek Standard: transient dip step ~60, recovery step ~90. 参数同 grpo_stage2_standard_20_v8。Parent: sft_standard_20_qwen_math.\", \"notes\": \"v2 restart with EOS fix (generation_config eos_token_id=[151643,151645]). Step speed ~27s/step (vs ~7min pre-fix). wandb run name: grpo_standard_qwen_math_v2.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T14:27:51.309Z\", \"wandb_run_id\": \"iq8nkk1p\"}, \"grpo_rasp_qwen_math\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-16T08:42:43.989Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% GRPO (100 steps, save_steps=5). 跨模型验证 C1/C2: GRPO collapse 是否在 Qwen Math 上复现。DeepSeek RASP collapse onset ~step 10 (permanent). 参数同 grpo_stage2_rasp_20_v9。Parent: sft_rasp_20_qwen_math.\", \"notes\": \"v2 restart with EOS fix (generation_config eos_token_id=[151643,151645]). Step speed ~27s/step (vs ~7min pre-fix). wandb run name: grpo_rasp_qwen_math_v2.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T14:27:50.618Z\", \"wandb_run_id\": \"2sgy2m1a\"}, \"eval_sft_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T07:05:10.825Z\", \"hypothesis\": \"Standard 25% post-SFT GSM8K eval (N=1319, greedy, seed=42). 对比 eval_sft_rasp_25 (同时在 westd 运行)，25% sparsity 下 RASP vs Standard post-SFT recovery 对比。20% 结果: Standard 64% > RASP 57%。Parent: sft_standard_25.\", \"metrics\": {\"accuracy\": 0.5125, \"avg_len\": 326.26, \"eos_rate\": 0.9545, \"n_correct\": 676, \"n_total\": 1319, \"stderr\": 0.0138}, \"parent\": \"sft_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T13:23:38.482Z\"}, \"eval_sft_qwen_math_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T12:04:49.969Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 25% post-SFT GSM8K eval (N=200, greedy, seed=42). Control for eval_sft_qwen_math_rasp_25。对比 20% 结果 (Standard 71.0%)。Parent: sft_qwen_math_standard_25.\", \"metrics\": {\"accuracy\": 63, \"correct\": 126, \"eos_rate\": 1, \"total\": 200}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T12:50:43.619Z\"}, \"eval_sft_qwen_math_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T12:04:49.248Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 25% post-SFT GSM8K eval (N=200, greedy, seed=42). 验证 25% sparsity 下 RASP SFT 恢复质量。对比 Standard 25% 和 20% 结果 (RASP 72.5% vs Standard 71.0%)。Parent: sft_qwen_math_rasp_25.\", \"metrics\": {\"accuracy\": 64, \"correct\": 128, \"eos_rate\": 0.995, \"total\": 200}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T12:50:42.647Z\"}, \"sft_qwen_math_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T11:15:20.187Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 25% SFT recovery (lr=2e-5, epochs=2). Control for sft_qwen_math_rasp_25. Parent: prune_standard_25_qwen_math.\", \"metrics\": {\"epochs\": 2, \"final_loss\": 0.6122, \"mean_token_accuracy\": 0.8607, \"throughput_samples_per_sec\": 8.973, \"total_steps\": 1870, \"train_runtime_sec\": 1666}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T12:04:20.943Z\"}, \"sft_qwen_math_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T11:15:13.431Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 25% SFT recovery (lr=2e-5, epochs=2). 验证更高稀疏度下 RASP 的跨模型 SFT 恢复。Parent: prune_rasp_25_qwen_math.\", \"metrics\": {\"epochs\": 2, \"final_loss\": 0.6062, \"mean_token_accuracy\": 0.8673, \"throughput_samples_per_sec\": 9.046, \"total_steps\": 1870, \"train_runtime_sec\": 1652}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T12:03:33.361Z\"}, \"eval_sft_standard_qwen_math_n200\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T11:15:10.910Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% post-SFT GSM8K eval (N=200, greedy, seed=42). EOS fixed. Control for eval_sft_rasp_qwen_math_n200. Parent: sft_standard_20_qwen_math.\", \"metrics\": {\"accuracy\": 0.71, \"avg_len\": 127.7, \"correct\": 142, \"eos_rate\": 1, \"n_total\": 200, \"stderr\": 0.0321}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T11:32:27.012Z\"}, \"eval_sft_rasp_qwen_math_n200\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T11:15:07.028Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% post-SFT GSM8K eval (N=200, greedy, seed=42). EOS fixed (eos_token_id=[151643,151645]). Cross-model validation. Parent: sft_rasp_20_qwen_math.\", \"metrics\": {\"accuracy\": 0.725, \"avg_len\": 121.8, \"correct\": 145, \"eos_rate\": 1, \"n_total\": 200, \"stderr\": 0.0316}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T11:32:23.931Z\"}, \"eval_sft_standard_qwen_math\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-16T08:42:43.023Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% post-SFT GSM8K eval (N=1319, greedy, seed=42). Control for eval_sft_rasp_qwen_math. Parent: sft_standard_20_qwen_math.\", \"notes\": \"Intentionally killed: N=1319 eval too slow (~5min/sample, ETA 4-5 days). Director approved Option A: restart with N=200.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T10:59:06.735Z\"}, \"eval_sft_rasp_qwen_math\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-16T08:42:42.080Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% post-SFT GSM8K eval (N=1319, greedy, seed=42). Cross-model validation of RASP SFT recovery. Parent: sft_rasp_20_qwen_math.\", \"notes\": \"Intentionally killed: N=1319 eval too slow (~5min/sample, ETA 4-5 days). Director approved Option A: restart with N=200. Replacement running as eval_sft_rasp_qwen_math_n200.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T10:58:59.633Z\"}, \"prune_rasp_rlvr_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T09:50:39.656Z\", \"hypothesis\": \"RASP-RLVR 20% pruning: score = importance * cka^alpha. 反转 CKA scoring——剪掉功能独特的结构（低 CKA overlap），保留冗余结构（高 overlap），使 RLVR 更容易通过冗余路径恢复能力。对比 RASP (1-cka)^alpha 和 Standard (importance only)。\", \"metrics\": {\"actual_sparsity\": 0.1909, \"attn_gqa_groups_pruned\": \"0/112\", \"group_selection_diff_vs_rasp\": \"RASP重剪前6层+后段(19,23-25,27)保中间; RLVR重剪前6层+中后段(16-26)保Layer6-7,27\", \"mlp_groups_pruned\": \"200/784\", \"params_after\": \"6.16B\", \"target_sparsity\": 0.2}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T10:31:42.144Z\"}, \"sft_standard_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:11:00.051Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% pruned SFT recovery. 验证 RASP 方法在第二个模型族上的 SFT 恢复效果。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T10:10:19.019Z\"}, \"sft_rasp_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:10:59.311Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% pruned SFT recovery. 验证 RASP 方法在第二个模型族上的 SFT 恢复效果。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T10:10:17.852Z\"}, \"prune_standard_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:03:56.378Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% structured pruning (negative control). Scope expansion Phase 2 对照组。\", \"metrics\": {\"attn_groups_pruned\": 0, \"mlp_groups_pruned\": 202, \"model_keys\": 339, \"original_params\": 7615616512, \"pruned_params\": 6147409408, \"sparsity_actual\": 0.1928, \"sparsity_target\": 0.2}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T08:04:22.864Z\"}, \"prune_rasp_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:01:57.095Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% structured pruning. Scope expansion Phase 2: 验证 RASP 在第二个模型上的有效性（CKA-guided pruning preserves reasoning across model families）。使用已计算的 importance_scores_qwen_math.pt + cka_scores_qwen_math.pt。\", \"metrics\": {\"alpha\": 1, \"attn_groups_pruned\": 0, \"mlp_groups_pruned\": 199, \"model_keys\": 339, \"original_params\": 7615616512, \"pruned_params\": 6169214464, \"sparsity_actual\": 0.1899, \"sparsity_target\": 0.2}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T08:04:20.185Z\"}, \"eval_grpo_rasp_v9_step10\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T03:40:46.186Z\", \"hypothesis\": \"RASP GRPO v9 step-10 checkpoint GSM8K eval (N=1319, greedy, seed=42). Step 10 = collapse onset (reward=0.015, frac_zero_std=0.875). 对比 step-5 eval 和 Standard step-50 eval (58.91%) 量化 collapse 影响。Parent: grpo_stage2_rasp_20_v9.\", \"metrics\": {\"accuracy\": 61.87, \"avg_response_length\": 213.6, \"correct\": 816, \"eos_rate\": 98.33, \"seed\": 42, \"stderr\": 1.34, \"total\": 1319, \"truncated\": 22}, \"parent\": \"grpo_stage2_rasp_20_v9\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T08:01:06.191Z\"}, \"eval_postprune_25\": {\"created_at\": \"2026-05-16T06:17:34.379Z\", \"hypothesis\": \"25% post-prune accuracy eval (N=100, greedy, seed=42) for both pruned_rasp_25 and pruned_standard_25. 补之前失败的数据点，对比 20% sparsity post-prune (RASP 31% vs Standard 27%)。\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-16T06:17:43.424Z\"}, \"eval_sft_standard_20_full\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T16:21:33.865Z\", \"hypothesis\": \"Standard post-SFT full GSM8K eval (N=1319, greedy, seed=42). N=100 result: 64%. Full eval provides statistical significance for RASP vs Standard comparison. Parent: sft_standard_20_retrain.\", \"notes\": \"Replaced by eval_sft_standard_20_n1319 (tmux session conflict). See new exp for results.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T05:35:33.677Z\"}, \"eval_grpo_rasp_v9_step5\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T01:55:35.424Z\", \"hypothesis\": \"RASP GRPO v9 step-5 checkpoint GSM8K eval (N=1319, greedy, seed=42). Step 5 是 RASP collapse 前最后可能的 pre-collapse checkpoint（v9 collapse onset ≤step 10, logging_steps=10 无法判断 step 5 状态）。与 Standard step-50 eval (58.91%) 对比，量化 RASP GRPO 短暂训练的效果。Parent: grpo_stage2_rasp_20_v9.\", \"metrics\": {\"accuracy\": 60.65, \"seed\": 42, \"total\": 1319}, \"parent\": \"grpo_stage2_rasp_20_v9\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T05:18:16.131Z\"}, \"prune_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T05:13:52.855Z\", \"hypothesis\": \"Standard importance-only pruning at 25% sparsity (calibration=256). Negative control for RASP 25%. Multi-sparsity extension.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T05:16:41.032Z\"}, \"prune_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T05:13:52.292Z\", \"hypothesis\": \"RASP pruning at 25% sparsity (α=1.0, calibration=256). Multi-sparsity extension: compare with 20% to establish sparsity-collapse relationship.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T05:16:39.998Z\"}, \"grpo_unpruned_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T01:45:10.586Z\", \"hypothesis\": \"D043+ Unpruned GRPO v2 (D041 fix) — 修复 v1 设计缺陷（无 SFT 步骤）。使用 sft_unpruned_baseline checkpoint (84% N=100, loss=0.332) → GRPO，与 v8 完全相同参数 (8-bit AdamW, max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, lr=1e-6, max_steps=100, save_steps=5)。三模型 collapse dynamics 最后一块拼图：RASP ~step10, Standard ~step60, Unpruned ?。如果 Unpruned collapse 显著晚于 pruned models → 确立 pruning-specificity (Claim 1/2)。如果 Unpruned 也快速 collapse → GRPO 方法本身问题，需重新 frame。Parent: sft_unpruned_baseline.\", \"metrics\": {\"avg_step_time_sec\": 23, \"checkpoints_available\": [\"checkpoint-90\", \"checkpoint-95\", \"checkpoint-100\"], \"collapse_onset\": \"N/A\", \"final_entropy\": 0.194, \"final_grad_norm\": 6.97, \"final_kl\": 0.0051, \"final_reward\": 0.661, \"max_steps\": 100, \"peak_reward\": 0.669, \"peak_reward_step\": 80, \"reward_range\": \"0.425-0.669\", \"training_seconds\": 2660}, \"notes\": \"Unpruned GRPO 100 步全程未 collapse。Reward 稳定 0.4-0.67，peak 0.669 (step 80)，final 0.661 (step 100)。Grad norm 健康 (2.45-14.94)，entropy 平稳 (0.184-0.214)，KL 极稳定 (0.0046-0.0053)。Step 30 有浅 dip (0.425) 但 step 40 即回升。三模型 severity gradient 确立：RASP collapse step~10 (永久) > Standard step~60 (transient) > Unpruned 无 collapse。save_total_limit 导致仅剩 checkpoint-90/95/100。W&B runs: nhsx0bt2 (首次), hwucjf2n (恢复)。\", \"parent\": \"sft_unpruned_baseline\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T04:43:16.844Z\", \"wandb_run_id\": \"hwucjf2n\"}, \"grpo_stage2_rasp_20_v9\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T22:37:13.593Z\", \"hypothesis\": \"D043 plan_003 (Claim 1 核心对比): RASP GRPO v9 — save_steps=5 捕获 collapse 前 peak checkpoint。v8 全版本零 checkpoint (save_steps=50, kill at step ~28)。v9 用 save_steps=5, save_total_limit=5, max_steps=30。其余参数与 v8 一致 (8-bit AdamW, max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, lr=1e-6)。RASP collapse onset ~step 10, 需要 step 5/10 checkpoint 做 eval 与 Standard step-50 对比。Parent: sft_rasp_20.\", \"metrics\": {\"checkpoints\": [\"checkpoint-10\", \"checkpoint-15\", \"checkpoint-20\", \"checkpoint-25\", \"checkpoint-30\"], \"collapse_note\": \"frac_zero_std peaked at 95% by step 30, reward dropped from peak 0.039 (step 20) to 0.021 (step 30)\", \"collapse_status\": \"COLLAPSED\", \"final_clipped_ratio\": 0.956, \"final_frac_zero_std\": 0.95, \"final_grad_norm\": 1.398, \"final_kl\": 0.00118, \"final_loss\": 0.00686, \"final_mean_length\": 996, \"final_mean_terminated_length\": 176, \"final_reward\": 0.021, \"max_steps\": 30, \"reward_history\": [{\"frac_zero_std\": 0.875, \"reward\": 0.015, \"step\": 10}, {\"frac_zero_std\": 0.8, \"reward\": 0.039, \"step\": 20}, {\"frac_zero_std\": 0.95, \"reward\": 0.021, \"step\": 30}], \"step\": 30, \"step_time_sec\": 418, \"total_time\": \"3h28m25s\", \"wandb_url\": \"https://wandb.ai/xiaoyucorynne-/recovery_aware_struct_prune/runs/mrikafz3\"}, \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T03:38:37.387Z\", \"wandb_run_id\": \"mrikafz3\"}, \"eval_sft_grasp_20_westd\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-15T15:22:44.271Z\", \"hypothesis\": \"GraSP post-SFT eval (N=100, greedy). Three-way comparison final piece: Standard 64%, RASP 57%, GraSP ?%. Tests whether GraSP pruning criterion affects SFT recovery potential. GraSP pre-SFT was ~8%, SFT training completed (loss=0.5857, token_acc=0.8392).\", \"metrics\": {\"avg_response_length\": 225.78, \"eos_rate\": 0.98, \"gsm8k_accuracy\": 0.41, \"gsm8k_accuracy_ci\": 0.0492, \"gsm8k_correct\": 41, \"gsm8k_total\": 100, \"max_response_length\": 4096, \"min_response_length\": 57, \"truncated\": 2}, \"notes\": \"OOM on westd cuda:1: GRPO grpo_unpruned_v2 (PID 75381) occupies 81GB/95GB, eval needs ~14GB additional, only 753MB free. GRPO at step 5/100, will take a long time. Need to wait for GRPO to finish or use another GPU.\", \"parent\": \"sft_grasp_20_westd\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T03:32:41.800Z\"}, \"grpo_stage2_standard_20_v8\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-15T14:32:39.107Z\", \"hypothesis\": \"D031: GRPO v8 Standard (negative control) — v7 disk crash fix + GPU mapping fix. HF cache redirected to data disk, CUDA_VISIBLE_DEVICES=1 + --gpu 0. 8-bit AdamW, max_completion_length=1024, identical params to RASP v8. Parent: sft_standard_20_retrain.\", \"metrics\": {\"checkpoint_50_eval\": {\"accuracy\": 0.5891, \"delta_vs_sft\": -0.0038}, \"checkpoint_50_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/grpo_stage2_standard_20_v8/checkpoint-50\", \"final_step\": 90, \"key_finding\": \"Standard experienced transient dip at step 60 but RECOVERED by step 90. RASP collapsed permanently by step 10. No step-100 checkpoint available.\", \"max_steps\": 100, \"status\": \"STOPPED_AT_90\", \"step_40_peak\": {\"frac_zero_std\": 0.45, \"grad_norm\": 3.45, \"reward\": 0.096}, \"step_50\": {\"frac_zero_std\": 0.6, \"grad_norm\": 2.09, \"reward\": 0.037}, \"step_60_dip\": {\"frac_zero_std\": 0.525, \"grad_norm\": 0.013, \"note\": \"transient instability\", \"reward\": 0.041}, \"step_90\": {\"frac_zero_std\": 0.475, \"grad_norm\": 2.14, \"note\": \"RECOVERED — healthy (from wandb)\", \"reward\": 0.065}, \"stopped_reason\": \"silent stop at step 90, no crash log, tmux session gone. Only checkpoint-50 on disk (save_steps=50).\"}, \"notes\": \"MAJOR REVISION: Step 60 was a transient instability dip, NOT permanent collapse. Step 90 metrics show full recovery (grad_norm=2.14, reward=0.065, frac_zero_std=0.475). Standard GRPO completed 100/100 steps with healthy final metrics. This contrasts sharply with RASP which collapsed permanently by step 10 (grad_norm=0.007). Three-model dynamics: RASP=permanent collapse (step ≤10), Standard=transient dip+recovery (step 60), Unpruned=TBD. Step-50 checkpoint eval showed 58.91% (Δ=-0.38pp from SFT) — GRPO training metrics recovered but accuracy did not improve. Need step-100 eval to check if recovery translated to accuracy gain.\", \"parent\": \"sft_standard_20_retrain\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T02:14:46.162Z\", \"wandb_run_id\": \"q34vz8j2\"}, \"alpha_ablation_sweep\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T20:15:39.765Z\", \"hypothesis\": \"plan_015 (Claim 2): α sensitivity ablation on westb (cal=512). Sweep α∈{0, 0.25, 0.5, 1, 2} at 20% sparsity. RASP scoring S(h)=I(h)×(1-F(h))^α. Each α: prune + post-prune GSM8K N=100 eval. Tests whether CKA weight α systematically affects post-prune reasoning retention. Prior westd (cal=256) results: α=0.0→30%, α=0.5→25%, α=1.0→27%, α=4.0→40% (non-monotonic). westb cal=512 may show different pattern due to group selection sensitivity at 20% sparsity.\", \"metrics\": {\"alpha_0.0\": {\"accuracy\": 0.27, \"avg_len\": 1192, \"eos_rate\": 0.8, \"n_correct\": 27, \"n_total\": 100}, \"alpha_0.25\": {\"accuracy\": 0.23, \"avg_len\": 1834, \"eos_rate\": 0.63, \"n_correct\": 23, \"n_total\": 100}, \"alpha_0.5\": {\"accuracy\": 0.22, \"avg_len\": 1141, \"eos_rate\": 0.81, \"n_correct\": 22, \"n_total\": 100}, \"alpha_1.0\": {\"accuracy\": 0.31, \"avg_len\": 733, \"eos_rate\": 0.92, \"n_correct\": 31, \"n_total\": 100}, \"alpha_2.0\": {\"accuracy\": 0.36, \"avg_len\": 2130, \"eos_rate\": 0.59, \"n_correct\": 36, \"n_total\": 100}}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T00:18:46.780Z\"}, \"sft_unpruned_baseline\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T22:07:43.929Z\", \"hypothesis\": \"D043 plan_002 (Claim 1): Unpruned DeepSeek-R1-Distill-Qwen-7B SFT baseline。与 RASP/Standard SFT 完全相同配置 (2 epochs, lr=2e-5, batch=1, grad_accum=8, GSM8K train, seed=42)。三方公平对比必要条件：unpruned SFT → 然后才能做 unpruned GRPO baseline (修复 D041 设计缺陷)。\", \"metrics\": {\"epochs\": 2, \"final_loss\": 0.3321, \"final_token_accuracy\": 0.909, \"total_steps\": 1870, \"train_loss_avg\": 0.4253, \"train_runtime_sec\": 1908, \"train_samples_per_second\": 7.833}, \"notes\": \"tmux session: sft_unpruned, westd cuda:1. 1870 steps (2 epochs), ETA ~35-40min from 06:30 UTC. Cleaned sft_ablation/alpha_4.0/checkpoint-1870 (35G) to free disk.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T00:18:44.096Z\"}, \"eval_sft_rasp_full_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T20:36:02.786Z\", \"hypothesis\": \"plan_001 (Claim 1): RASP SFT full GSM8K eval (N=1319, greedy, seed=42) on westd. N=100 results: westb 57%, westd 67% (10pp gap, needs full eval to confirm). Full eval resolves whether RASP advantage is real or N=100 noise. Parent: sft_rasp_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.6149, \"avg_len\": 216.5, \"eos_rate\": 0.9826, \"n_correct\": 811, \"n_total\": 1319, \"stderr\": 0.0134}, \"status\": \"DONE\", \"updated_at\": \"2026-05-15T21:42:41.916Z\"}, \"eval_sft_standard_full_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T20:36:01.803Z\", \"hypothesis\": \"plan_001 (Claim 1): Standard SFT full GSM8K eval (N=1319, greedy, seed=42) on westd. N=100 results: westb 64%, westd 63% (cross-server consistent). Full eval for statistical significance. Parent: sft_standard_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.5929, \"avg_len\": 226.7, \"eos_rate\": 0.9803, \"n_correct\": 782, \"n_total\": 1319, \"stderr\": 0.01353}, \"status\": \"DONE\", \"updated_at\": \"2026-05-15T21:42:40.854Z\"}, \"grpo_unpruned_baseline\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T17:29:03.104Z\", \"hypothesis\": \"D032: Unpruned baseline GRPO — 证明 GRPO 本身在未剪枝 DeepSeek-R1-Distill-Qwen-7B 上有效。如果 RASP/Standard 剪枝模型 collapse 而 unpruned 不 collapse，证明 collapse 是剪枝导致的，不是 GRPO 方法问题。Reviewer 关键缺失证据。参数与 v8 完全一致。\", \"metrics\": {\"checkpoint_saved\": false, \"collapse_onset_step\": 80, \"disk_full\": true, \"final_clipped_ratio\": 1, \"final_frac_zero_std\": 1, \"final_mean_terminated_length\": 0, \"final_reward\": 0, \"peak_reward\": 0.044, \"peak_reward_step\": 20, \"runtime_min\": 49, \"steps_completed\": 100}, \"notes\": \"磁盘满崩溃 + 实验设计缺陷（无 SFT 对照）。100/100 steps 但 checkpoint 保存失败 (250G/250G)。Peak reward 0.044 (step 20) → step 80 collapse。W&B: e49c42ha。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T20:35:34.577Z\", \"wandb_run_id\": \"e49c42ha\"}, \"eval_sft_rasp_20_westd_n100_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T19:24:08.437Z\", \"hypothesis\": \"N=100 quick validation of RASP SFT retrain on westd (v2 retry — fixed working directory from autodl-tmp to project root). Expected ~57% (matching westb). Cross-server reproducibility check. Parent: sft_rasp_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.67, \"avg_len\": 182.39, \"eos_rate\": 0.99, \"n_correct\": 67, \"n_total\": 100}, \"status\": \"DONE\", \"updated_at\": \"2026-05-15T20:11:02.033Z\"}, \"eval_sft_standard_20_westd_n100_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T19:24:09.850Z\", \"hypothesis\": \"N=100 quick validation of Standard SFT retrain on westd (v2 retry — fixed working directory + output_path typo). Expected ~64% (matching westb). Cross-server reproducibility check. Parent: sft_standard_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.63, \"avg_len\": 260.57, \"eos_rate\": 0.97, \"n_correct\": 63, \"n_total\": 100}, \"status\": \"DONE\", \"updated_at\": \"2026-05-15T20:11:00.967Z\"}, \"eval_sft_standard_20_westd_n100\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T17:39:03.607Z\", \"hypothesis\": \"N=100 quick validation of Standard SFT retrain on westd. Expected ~64% (matching westb). Cross-server reproducibility check before N=1319 full eval. Parent: sft_standard_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.63, \"avg_len\": 260.57, \"eos_rate\": 0.97, \"n_correct\": 63, \"n_total\": 100, \"stderr\": 0.048}, \"notes\": \"Standard 63% on westd — matches westb expectation (~64%). Cross-server reproducibility confirmed for Standard. RASP outperforms Standard by 4pp on westd (67% vs 63%), reversed from westb pattern.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T19:30:00.797Z\"}, \"eval_sft_rasp_20_westd_n100\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T17:35:08.417Z\", \"hypothesis\": \"N=100 quick validation of RASP SFT retrain on westd. Expected ~57% (matching westb). Cross-server reproducibility check before N=1319 full eval. Parent: sft_rasp_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.67, \"avg_len\": 182.39, \"eos_rate\": 0.99, \"n_correct\": 67, \"n_total\": 100, \"stderr\": 0.047}, \"notes\": \"RASP 67% vs expected ~57% — 10pp higher than westb. Standard 63% matches westb expectation. RASP > Standard by 4pp on westd (reversed from westb where Standard led). Cross-server reproducibility NOT confirmed for RASP — needs investigation with full N=1319 eval.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T19:29:59.250Z\"}, \"sft_rasp_20_westd_retrain\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T16:59:51.103Z\", \"hypothesis\": \"RASP SFT retrain on westd for cross-server reproducibility + full N=1319 eval. Same params as westb (2 epochs, lr=2e-5, batch=1, grad_accum=8, seed=42). Expected: ~57% post-SFT (matching westb). Parent: reeval_postprune_definitive.\", \"notes\": \"RASP SFT retrain 启动 on westd cuda:0. PID 48946, tmux session sft_rasp_westd. 参数: epochs=2, lr=2e-5, bs=1, grad_accum=8, max_seq_len=2048, seed=42. Output: /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd. 预计 ~35-40min。完成后先 N=100 快速验证 (~57% expected)，再 N=1319 full eval。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T18:36:33.103Z\"}, \"sft_standard_20_westd_retrain\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T17:05:52.927Z\", \"hypothesis\": \"Standard SFT retrain on westd for cross-server reproducibility + full N=1319 eval. Same params as westb (2 epochs, lr=2e-5, batch=1, grad_accum=8, seed=42). Expected: ~64% post-SFT (matching westb). Parent: reeval_postprune_definitive.\", \"metrics\": {\"epochs\": 2, \"final_step_loss\": 0.6403, \"final_token_accuracy\": 0.8258, \"total_steps\": 1870, \"train_loss\": 0.7577, \"train_runtime_sec\": 1679, \"train_samples_per_second\": 8.902}, \"notes\": \"Standard SFT retrain 启动 on westd cuda:1. PID 49645. 参数: epochs=2, lr=2e-5, bs=1, grad_accum=8, max_seq_len=2048, seed=42. Output: /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_westd. 模型加载中。预计 ~35-40min。完成后先 N=100 快速验证 (~64% expected)，再 N=1319 full eval。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T18:36:32.558Z\"}, \"grpo_stage2_rasp_20_v8\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-15T14:32:38.536Z\", \"hypothesis\": \"D031: GRPO v8 RASP — v7 disk crash fix. HF cache redirected to data disk. 8-bit AdamW, max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True, 100 steps. Parent: sft_rasp_20.\", \"metrics\": {\"clipped_ratio\": 0.963, \"completion_length\": 996, \"entropy\": 0.065, \"est_step30_utc\": \"2026-05-15T18:03:00Z\", \"frac_zero_std\": 0.9, \"grad_norm\": 0.011, \"kill_at_step_30\": true, \"kill_reason\": \"All 3 thresholds met: grad_norm=0.011<0.05, frac_zero_std=0.90>=0.85, reward=0.026<0.03\", \"kl\": 0.001, \"loss\": -0.005, \"reward_mean\": 0.026, \"status\": \"COLLAPSED\", \"step\": 23, \"terminated_length\": 124}, \"notes\": \"NEGATIVE: Killed at ~step 28-30 per Director protocol. All 3 kill thresholds met since step 10: grad_norm=0.011&lt;0.05, frac_zero_std=0.90≥0.85, reward=0.026&lt;0.03. RASP GRPO 三次连续 collapse (v2/v5/v8)——所有配置（lr, temp, rep_penalty, beta, loss_type）均无法阻止 collapse。结论: RASP 剪枝模型的 GRPO 恢复路径在当前框架下失效。cuda:0 已释放给 unpruned baseline GRPO。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T17:53:21.521Z\", \"wandb_run_id\": \"0wz7xpd5\"}, \"grasp_baseline_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T12:40:34.072Z\", \"hypothesis\": \"D027: GraSP baseline on westd — compare GraSP pruning criterion against RASP at 20% sparsity. If RASP > GraSP post-recovery, confirms CKA-aware scoring advantage over gradient-based saliency. Critical for plan_005 and Dream reviewer concern.\", \"metrics\": {\"avg_len\": 4018, \"eos_rate\": 0.02, \"grasp_20_accuracy_n100\": 0.07, \"json_path\": \"results/eval_pruned_graspune_20_greedy.json\", \"n_correct\": 7, \"n_total\": 100, \"rasp_20_accuracy_ref\": 0.31, \"standard_20_accuracy_ref\": 0.27}, \"notes\": \"GraSP post-prune eval (N=100) 运行中 on westd GPU 0. PID 38120. 71/100 at 15:25 UTC, ~51s/sample, 预计 ~25min 完成。中间结果 (50 samples): accuracy 6%, eos_rate 2%, avg_len 4018. 输出确认安全: seed 默认 42, output_path 默认 results/eval_pruned_graspune_20_greedy.json. 完成后立即启动 GraSP post-SFT eval (cuda:0, model at sft_graspune_20/). Cron 监控中。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T17:12:21.555Z\"}, \"eval_sft_alpha_2p0\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T15:42:36.917Z\", \"hypothesis\": \"α=2.0 post-SFT GSM8K eval (N=100, greedy). Post-prune 29%, post-SFT loss=0.61, token_acc=0.84. Completes α ablation sweep: α=0.0 (64%), α=1.0 (57%), α=4.0 (62%), α=2.0 (?). Parent: sft_alpha2_0_westd.\", \"metrics\": {\"accuracy\": 0.62, \"avg_len\": 277.41, \"eos_rate\": 0.97, \"n_correct\": 62, \"n_total\": 100, \"stderr\": 0.0485}, \"parent\": \"sft_alpha2_0_westd\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T16:41:41.929Z\"}, \"sft_alpha2_0_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T14:32:54.953Z\", \"hypothesis\": \"D027: α=2.0 pruned model SFT recovery on westd. α=2.0 post-prune accuracy 29%. Same SFT params as other α variants (2 epochs, lr=2e-5, batch=1, grad_accum=8). Completes α ablation sweep.\", \"metrics\": {\"epoch\": 2, \"mean_token_accuracy_final\": 0.8354, \"post_prune_accuracy\": 0.29, \"total_steps\": 1870, \"train_loss\": 0.7424, \"train_loss_final\": 0.6114, \"train_runtime_sec\": 2422}, \"notes\": \"α=2.0 SFT 完成 (1870/1870 steps, 2 epochs, ~40min). train_loss=0.7424, final loss=0.6114, token_acc=0.8354. Post-prune 29% → post-SFT 需 eval 确认. Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_ablation/alpha_2.0 (model.safetensors 11.5GB).\", \"parent\": \"alpha_ablation_westd_cal256\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T15:41:31.384Z\"}, \"grpo_standard_20_v8\": {\"created_at\": \"2026-05-15T15:07:46.100Z\", \"notes\": \"[2026-05-15 23:05] Early signal check: step 2/100, ~411s/step, ETA ~11.2h. GPU1 72GB/98GB VRAM, 100% util. Wandb metrics not yet logged (logging_steps=10, first log at step 10 ~55min). Processes alive (PID 534667, 22min uptime, 3.1GB RSS). WARNING: data disk 89% full (29GB free), checkpoint save at step 50 may fail.\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-15T15:07:46.100Z\"}, \"grpo_rasp_20_v8\": {\"created_at\": \"2026-05-15T15:07:44.307Z\", \"notes\": \"[2026-05-15 23:05] Early signal check: step 3/100, ~400s/step, ETA ~10.8h. GPU0 72GB/98GB VRAM, 100% util. Wandb metrics not yet logged (logging_steps=10, first log at step 10 ~47min). Processes alive (PID 532861, 31min uptime, 3.1GB RSS). WARNING: data disk 89% full (29GB free), checkpoint save at step 50 may fail (~18-24GB per checkpoint).\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-15T15:07:44.307Z\"}, \"alpha_ablation_westd_cal256\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T09:46:30.119Z\", \"hypothesis\": \"α ablation sweep (calibration=256, N=100). α∈{0.0,0.5,1.0,2.0,4.0} at 20% sparsity. Phase A (prune+eval) complete, Phase B (SFT) in progress. Note: calibration=256 differs from westb original (512), causing ~5% group selection differences.\", \"metrics\": {\"alpha_4_0_accuracy\": 0.4, \"finding\": \"α=4.0 gives 40% post-prune accuracy (highest), non-monotonic relationship between α and accuracy\"}, \"notes\": \"α ablation (calibration=256, N=100) Phase A 完成. Phase B (SFT) 状态: α=0.0 SFT+eval DONE (64%), α=0.5 SFT DONE (checkpoint at /root/autodl-tmp/recovery_aware_struct_prune/sft_ablation/alpha_0.5/, eval 待做), α=1.0 SFT DONE + eval running, α=2.0 SFT running (240/1870), α=4.0 SFT+eval DONE (62%). α=4.0 达到 40% post-prune accuracy 为最高, α 与 accuracy 呈非单调关系. Note: calibration=256 differs from westb original (512).\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-15T15:07:37.593Z\"}, \"sft_grasp_20_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T13:50:39.294Z\", \"hypothesis\": \"D028: GraSP pruned model (8% post-prune) SFT recovery. Same params as RASP/Standard SFT (2 epochs, lr=2e-5, batch=1, grad_accum=8). Completes three-way comparison: Standard 27%→64%, RASP 31%→57%, GraSP 8%→?. Tests whether importance metric choice affects recovery potential.\", \"notes\": \"GraSP SFT 完成 (exit_code=0). 1870/1870 steps, 2 epochs, 58.5min. Final loss=0.5857, mean_token_accuracy=0.8392, grad_norm=9.375. train_runtime=3510s, train_loss=0.706. Model saved to /root/autodl-tmp/recovery_aware_struct_prune/sft_graspune_20/ (12.6GB). GraSP eval (N=100) 仍在 GPU 0 运行中 (PID 38120, 41/100, ~1.5h remaining).\", \"parent\": \"grasp_baseline_westd\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T15:01:02.359Z\"}, \"grpo_stage2_standard_20_v7\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T14:06:22.084Z\", \"hypothesis\": \"D030: GRPO v7 — v6 OOM fix. 8-bit AdamW optimizer (bitsandbytes) saves ~50% optimizer memory. max_steps=100 (~756s/step). All other params same as v6: max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True, monkey-patch ref_model.\", \"notes\": \"v7 crashed: No space left on device — HF datasets cache 写入根分区导致瞬时磁盘满。GPU 映射 bug (--gpu 1 应为 --gpu 0 with CUDA_VISIBLE_DEVICES=1) 也未修复。v8 修复: HF_DATASETS_CACHE + HF_HOME 重定向到 autodl-tmp + GPU 映射修正。\", \"parent\": \"sft_standard_20_retrain\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T14:32:00.808Z\"}, \"grpo_stage2_rasp_20_v7\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T14:06:21.430Z\", \"hypothesis\": \"D030: GRPO v7 — v6 OOM fix. 8-bit AdamW optimizer (bitsandbytes) saves ~50% optimizer memory. max_steps=100 (~756s/step). All other params same as v6: max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True, monkey-patch ref_model.\", \"notes\": \"v7 crashed: RASP 静默死亡（可能 No space left on device 同根因），Standard 报 No space left on device — HF datasets cache 写入根分区导致瞬时磁盘满。双卡空闲 40+ min。v8 修复: HF_DATASETS_CACHE=/root/autodl-tmp/.hf_cache/datasets + HF_HOME=/root/autodl-tmp/.hf_cache。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T14:31:57.799Z\"}, \"grpo_stage2_standard_20_v6\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T12:42:36.011Z\", \"hypothesis\": \"D028: GRPO v6 Standard (negative control) — identical params to RASP v6: max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True. Direct comparison with RASP v6. If RASP >> Standard, confirms CKA-aware pruning preserves RLVR-recoverable structures.\", \"notes\": \"OOM at step 9/250. Adam._init_group() 分配 1.02 GiB 失败，GPU 0 仅剩 214 MiB。ref_model + train_model 占满 ~95 GiB。PID 521089 僵尸进程仍占 74318 MiB on GPU 1。同 RASP v6 根因。需要 8-bit optimizer 或 ref_model CPU offload。\", \"parent\": \"sft_standard_20_retrain\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T14:02:45.251Z\"}, \"grpo_stage2_rasp_20_v6\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T12:42:34.281Z\", \"hypothesis\": \"D028: GRPO v6 RASP — v5 truncation fix. max_completion_length 512→1024. All other params same: beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True, monkey-patch ref_model. v5 collapsed at step 80 (reward=0, clipped_ratio=97.5%). Expected ~5 min/step, ~21h total.\", \"notes\": \"OOM at step 9/250. Adam._init_group() 分配 130 MiB 失败，GPU 0 仅剩 44 MiB。ref_model + train_model 占满 ~95 GiB。PID 520997 僵尸进程仍占 67430 MiB。max_completion_length=1024, gradient_checkpointing=true, beta=0.01, temp=0.4, lr=1e-6, loss=dapo。需要 8-bit optimizer 或 ref_model CPU offload。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T14:02:43.049Z\"}, \"sft_alpha4_0_westd_retry\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T12:46:36.918Z\", \"hypothesis\": \"D027: α=4.0 pruned model SFT recovery on westd (retry #3). α=4.0 gave highest post-prune accuracy (40%). Fix: CUDA_VISIBLE_DEVICES=1 + --gpu 0 (prevent GPU 0 collision with GraSP) + --save_strategy no (prevent checkpoint serialization crash). Same SFT params: 2 epochs, lr=2e-5, batch=1, grad_accum=8.\", \"metrics\": {\"accuracy_stderr\": 0.049, \"avg_response_length\": 238.56, \"eos_rate\": 0.98, \"mean_token_accuracy_final\": 0.8368, \"n_correct\": 62, \"n_total\": 100, \"post_prune_accuracy\": 0.4, \"post_sft_accuracy_100\": 0.62, \"sft_recovery_gain_pp\": 22, \"train_loss_final\": 0.7393, \"train_loss_last_logged\": 0.6106}, \"notes\": \"SFT training completed (1870/1870 steps, 2 epochs, ~30 min). GSM8K eval (N=100, greedy): 62% accuracy (62/100, stderr=0.049), EOS rate 98%, avg_len 238.56. Post-prune 40% → post-SFT 62% (+22pp recovery). Compared to α=1.0 RASP post-SFT (57%), α=4.0 is +5pp higher, confirming higher α amplifies recovery. Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_ablation/alpha_4.0. Eval JSON: results/eval_alpha_4.0_greedy.json.\", \"parent\": \"alpha_ablation_westd_cal256\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T13:48:13.666Z\"}, \"sft_alpha4_0_westd\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T12:38:41.395Z\", \"hypothesis\": \"D027: α=4.0 pruned model SFT recovery on westd. α=4.0 gave highest post-prune accuracy (40%), testing if SFT recovery further amplifies the advantage. Same SFT params as other α variants (2 epochs, lr=2e-5, batch=1, grad_accum=8).\", \"notes\": \"第一次运行因 save_strategy=\\\"epoch\\\" 中间 checkpoint 序列化占满磁盘而失败。已修改 sft_recovery.py save_strategy=\\\"no\\\"，通过 sft_alpha4_0_westd_retry 重试。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T12:47:41.297Z\"}, \"grpo_stage2_rasp_20_v5\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-15T09:33:29.974Z\", \"hypothesis\": \"D025: GRPO v5 — v4 speed fix. max_completion_length 2048→512 (4x faster generation). All other params same as v4: beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True, monkey-patch ref_model. Expected ~7-10 min/step (vs v4 29min/step).\", \"notes\": \"D027: GRPO v5 RASP 实质性崩溃。Step 40 reward 峰值 0.033，step 80 归零（frac_zero_std=100%）。Grad norm: 2.6→0.01。Clipped ratio 93-97.5%（几乎所有 completion 被截断在 512 tokens）。根因：max_completion_length=512 对 R1 distill 模型不够长，模型无法在 512 token 内完成推理链。Step 89/250, ETA ~5h。建议 kill 并切 v6 (max_completion_length=1024)。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T12:43:46.085Z\"}, \"grpo_stage2_standard_20_v5\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-15T12:35:49.283Z\", \"hypothesis\": \"D027: GRPO v5 Standard (negative control) — identical params to RASP GRPO v5: beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, max_completion_length=512, gradient_checkpointing=True, monkey-patch ref_model. Direct comparison with grpo_stage2_rasp_20_v5. If RASP >> Standard, confirms CKA-aware pruning preserves RLVR-recoverable structures.\", \"notes\": \"First attempt failed (EXIT_CODE=2, --steps_per_generation not in argparse). Resubmitted without that arg. pid=518903. Model loading in progress.\", \"parent\": \"sft_standard_20_retrain\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-15T12:42:34.945Z\"}, \"reeval_postprune_definitive\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T09:46:32.498Z\", \"hypothesis\": \"D023: Definitive re-eval of pruned_standard_20 and pruned_rasp_20 with current eval_gsm8k.py + load_pruned_model. N=100, max_new_tokens=4096, greedy. Validates whether original 1% vs 29% is reproducible with current code.\", \"metrics\": {\"conclusion\": \"Original 29x advantage (29% vs 1%) not reproducible. Actual gap 4pp (31% vs 27% on westb), not statistically significant.\", \"original_claim_rasp\": 0.29, \"original_claim_standard\": 0.01, \"rasp_20_accuracy_westb\": 0.31, \"rasp_20_accuracy_westd\": 0.29, \"rasp_vs_standard_gap_pp\": 4, \"standard_20_accuracy_westb\": 0.27}, \"notes\": \"D023 definitive re-eval complete. westb: RASP 31%, Standard 27% (4pp gap). westd: RASP 29% (2pp delta from westb due to GPU driver 580 vs 595). Original 29% vs 1% claim invalidated — Standard was never 1%, likely eval bug in v4 pipeline. Post-prune gap is ~4pp, not statistically significant at N=100. GRPO Stage 2 is now the sole deterministic experiment for the paper narrative.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T12:30:41.698Z\"}, \"grpo_stage2_rasp_20_v4\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-15T08:23:49.573Z\", \"hypothesis\": \"D021: GRPO v4 — fixes v2/v3 collapse. Ref_model monkey-patch for beta=0.01 KL penalty, temp 0.4 (from 0.7), repetition_penalty 1.15, format_reward +0.1 for \\\\boxed{}, gradient_checkpointing=True, max_completion_length=2048. If reward>0 at step 10, confirms sampling stabilization.\", \"notes\": \"Killed at step ~1/250 due to 29min/step ETA (120h total). vLLM incompatible with per_layer_intermediate_size. Replaced by v5 with max_completion_length=512.\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T09:32:41.159Z\", \"wandb_run_id\": \"75d1o9wa\"}, \"grpo_stage2_rasp_20_v3\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T07:58:52.482Z\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T09:32:34.875Z\"}, \"grpo_stage2_standard_20_v2\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T03:30:01.400Z\", \"hypothesis\": \"D017: GRPO Stage 2 v2 negative control — SFT-warmed Standard-pruned model GRPO recovery with optimized params (max_completion_length=1024, max_samples=1000). Post-SFT: 64% greedy accuracy, EOS 99%, avg_len 176 tokens. Expected: GRPO improvement smaller than RASP counterpart.\", \"notes\": \"D019: GRPO Stage 2 v2 Standard (negative control) — EXIT_CODE=129 (SIGHUP) at step 33/250 (~4h05m, retry_count=1). Confirmed grad_norm=0 collapse: sampling mode (temp=0.7) produces degenerate output (\\\"#### 7248\\\" repeated), reward=0.00, 0 gradient. Despite SFT restoring 64% greedy accuracy and 99% EOS, GRPO sampling destabilizes the pruned model into repetitive loops. Same root cause as RASP counterpart — GRPO method failure, not model-specific.\", \"parent\": \"sft_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T08:15:31.861Z\", \"wandb_run_id\": \"iinlgfqk\"}, \"grpo_stage2_rasp_20_v2\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-15T03:30:00.666Z\", \"hypothesis\": \"D017: GRPO Stage 2 v2 — SFT-warmed RASP-pruned model RLVR recovery with optimized params (max_completion_length=1024, max_samples=1000). Post-SFT: 57% greedy accuracy, EOS 99%, avg_len 180 tokens. Reduced completion length justified by SFT restoring EOS. If GRPO pushes RASP significantly above Standard, confirms CKA-aware pruning preserves RLVR-recoverable structures.\", \"notes\": \"D019: GRPO Stage 2 v2 RASP — killed at step 35/250 (~4h17m). Confirmed grad_norm=0 collapse: sampling mode (temp=0.7) produces degenerate repetitive loops (e.g. \\\"$708033600000\\\" repeated 20+ steps), 0 reward, 0 gradient. Despite SFT restoring 57% greedy accuracy and 99% EOS rate, GRPO sampling destabilizes the pruned model. Same root cause as Standard counterpart. This is a GRPO method failure, not a RASP vs Standard comparison. wandb: e16rbclf.\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T08:15:30.925Z\", \"wandb_run_id\": \"e16rbclf\"}, \"grpo_stage2_standard_20\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-15T01:11:12.341Z\", \"hypothesis\": \"GRPO Stage 2 negative control: SFT-warmed Standard-pruned model GRPO recovery. Post-SFT accuracy 64% (greedy eval N=100), EOS restored. Expected: GRPO improvement smaller than RASP counterpart, confirming standard pruning removes structures less amenable to RLVR recovery.\", \"notes\": \"D017: Killed for parameter optimization restart. max_completion_length 4096→1024 (SFT后EOS 99%, avg 176 tokens, 4096浪费). max_samples 2000→1000. Superseded by grpo_stage2_standard_20_v2.\", \"parent\": \"sft_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T03:33:30.780Z\"}, \"grpo_stage2_rasp_20\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-15T01:11:10.490Z\", \"hypothesis\": \"GRPO Stage 2 (plan_003): SFT-warmed RASP-pruned model recovers reasoning via RLVR. Post-SFT accuracy 57% (greedy eval N=100), EOS restored. If GRPO pushes RASP significantly above Standard, confirms CKA-aware pruning preserves RLVR-recoverable structures.\", \"notes\": \"D017: Killed for parameter optimization restart. max_completion_length 4096→1024 (SFT后EOS 99%, avg 176 tokens, 4096浪费). max_samples 2000→1000. Superseded by grpo_stage2_rasp_20_v2.\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T03:33:11.856Z\"}, \"sft_standard_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-14T23:37:34.863Z\", \"hypothesis\": \"D013 Stage 1: SFT warmup on Standard-pruned model (20%, 1% GSM8K) as negative control. Expected: SFT partially recovers format but reasoning remains limited.\", \"metrics\": {\"eos_rate_greedy_100\": 0.99, \"greedy_accuracy_100\": 0.64, \"greedy_avg_len\": 176.31, \"greedy_correct\": 64, \"greedy_max_len\": 4096, \"greedy_min_len\": 43, \"greedy_total\": 100, \"sampling_eos_rate_5\": 1, \"token_accuracy\": 0.83, \"total_steps\": 1870, \"train_loss_final\": 0.64, \"train_loss_initial\": 1.7, \"train_time_min\": 37}, \"notes\": \"SFT warmup SUCCESS (负对照). EOS恢复100% (3/3测试). Loss 1.70→0.64, token_accuracy 83%. 但推理准确率有限(2/3, 12+15算成41), 说明standard pruning破坏了关键推理结构, SFT只恢复了格式+EOS, 无法完全恢复数学推理. 平均生成49 tokens, 无重复循环. 训练37min, 1870 steps. Greedy eval N=100: 64% accuracy, avg_len=176.31, eos_rate=99%. N=100 sampling eval was killed (OOM by concurrent GRPO). Eval JSON: /root/recovery_aware_struct_prune/results/eval_sft_standard_20_combined.json. Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20/\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T02:49:41.141Z\"}, \"sft_rasp_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-14T23:37:33.162Z\", \"hypothesis\": \"D013 Stage 1: SFT warmup on RASP-pruned model (20%, 29% GSM8K) to restore EOS generation ability before GRPO Stage 2.\", \"metrics\": {\"eos_rate_greedy_100\": 0.99, \"greedy_accuracy_100\": 0.57, \"greedy_avg_len\": 179.83, \"greedy_correct\": 57, \"greedy_max_len\": 4096, \"greedy_min_len\": 59, \"greedy_total\": 100, \"sampling_eos_rate_5\": 1, \"token_accuracy\": 0.83, \"total_steps\": 1870, \"train_loss_final\": 0.64, \"train_loss_initial\": 1.86, \"train_time_min\": 37}, \"notes\": \"SFT warmup SUCCESS. EOS恢复100% (5/5测试). Loss 1.86→0.64, token_accuracy 83%. 平均生成77 tokens, 无重复循环, 遵循GSM8K格式. 训练时间37min, 1870 steps (2 epochs). Greedy eval N=100: 57% accuracy, avg_len=179.83, eos_rate=99%. N=100 sampling eval was killed (OOM by concurrent GRPO). Eval JSON: /root/recovery_aware_struct_prune/results/eval_sft_rasp_20_combined.json. Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20/\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T02:49:39.222Z\"}, \"grpo_rasp_20_4096\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-14T22:43:12.378Z\", \"hypothesis\": \"D010: RASP-pruned model (20% sparsity, post-prune 29% GSM8K) GRPO recovery with max_completion_length=4096 (fix D009 truncation). Core MVP experiment — if recovery succeeds, RASP structure selection enables RLVR recovery that standard pruning cannot.\", \"notes\": \"D013: Killed at step 10/500. clipped_ratio=1.0, grad_norm=0, mean_terminated_length=0. RASP model (29% greedy accuracy) completely degrades in sampling mode (temp=0.7): repetitive loops and digit sequences, never produces EOS. 4096 tokens not the issue — pruning destroys sampling-mode generation quality. Same root cause as Standard. Switched to SFT warmup → GRPO two-stage recovery (D013). wandb: ccx0jr0z.\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T23:54:07.328Z\"}, \"grpo_standard_20_4096\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-14T22:19:37.356Z\", \"hypothesis\": \"D010: Standard-pruned model (20% sparsity, post-prune 1% GSM8K) GRPO recovery with max_completion_length=4096 (fix D009 truncation). Negative control — expected to fail recovery due to non-optimal structure selection, confirming RASP advantage.\", \"notes\": \"D011: Killed at step 10/500. 10步零梯度确认不可恢复——clipped_ratio=0.9938, grad_norm=0, loss≈0, reward=0.00625. 根因不是token长度不足,而是模型能力丧失(1% accuracy → 输出无意义重复数字,无法产出EOS). 即使8192/16384也无济于事. 作为负对照证据保留10步日志+wandb(ou02s4k4). Checkpoint: /root/autodl-tmp/recovered_standard_20_4096/\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T23:17:13.491Z\"}, \"grpo_standard_20_fast\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-14T17:38:55.838Z\", \"hypothesis\": \"Standard-pruned model (20% sparsity, post-prune 1% GSM8K) expected to fail GRPO recovery (RewardDesertCallback triggers). This is the negative control — confirms RASP's structure selection enables recovery that standard pruning cannot.\", \"notes\": \"[D009 INCONCLUSIVE — truncation artifact, not true negative] Training completed 500/500 steps (3h31m). Zero effective learning — reward stayed ~0.006-0.019 throughout, grad_norm=0, loss=0. All completions clipped at max_length=1024, 0 natural terminations. Root cause: max_completion_length=1024 too short for R1 CoT reasoning (needs 2000-4000 tokens). GRPO never received gradient signal. Hypothesis untested. wandb: ou02s4k4. Checkpoint: /root/autodl-tmp/recovered_standard_20/ (deleted, no value). Superseded by D010 grpo_standard_20_4096.\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T22:18:03.971Z\"}, \"grpo_rasp_20_fast\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-14T17:38:53.540Z\", \"hypothesis\": \"RASP-pruned model (20% sparsity, post-prune 29% GSM8K) recovers under GRPO RLVR with fast config (1024 tokens, 1 epoch, 2000 samples). Expected: reward > 0, meaningful recovery within 500 steps.\", \"notes\": \"[D009 INCONCLUSIVE — truncation artifact, not true negative] Training completed 500/500 steps (3h32m). Zero effective learning — reward stayed ~0.006-0.019 throughout, grad_norm=0, loss=0. All completions clipped at max_length=1024, 0 natural terminations. Root cause: max_completion_length=1024 too short for R1 CoT reasoning (needs 2000-4000 tokens). GRPO never received gradient signal. Hypothesis untested. wandb: sz9264sx. Checkpoint: /root/autodl-tmp/recovered_rasp_20/ (deleted, no value). Superseded by D010 grpo_rasp_20_4096.\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T22:18:01.563Z\"}, \"mvp_rasp_pipeline_v4\": {\"created_at\": \"2026-05-14T15:14:18.821Z\", \"hypothesis\": \"CKA functional overlap F(h) predicts structured pruning recoverability under RLVR. RASP scoring S(h)=I(h)×(1-F(h))^α selects structures whose removal is more recoverable via GRPO RLVR than standard importance-only pruning. V4: Dual sparsity probe (20% + 25%) to find viable operating point where pruned models retain >5% accuracy, then GRPO recovery comparison.\", \"notes\": \"GSM8K eval (100 samples, max_new_tokens=4096) partial results:\\n- baseline (Qwen2.5-7B): 94% (eval_baseline_7b_quick_fixed.json)\\n- rasp_20: 29% (eval_pruned_rasp_20_quick.json)\\n- standard_20: 1% (eval_pruned_standard_20_quick.json)\\n- standard_25: INCOMPLETE (killed at 72/100 by GRPO training OOM)\\n- rasp_25: NOT STARTED (GRPO training took GPUs)\\nKey finding: RASP 20% pruning retains 29% vs standard 1% — 29x advantage. GRPO recovery training now running on both GPUs (recovered_rasp_20 on GPU0, recovered_standard_20 on GPU1). standard_25 and rasp_25 eval need re-run after training completes.\", \"parent\": \"mvp_rasp_pipeline_v3\", \"status\": \"PREPARING\", \"updated_at\": \"2026-05-14T17:53:39.178Z\"}, \"grpo_standard_20\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-14T17:11:33.478Z\", \"hypothesis\": \"Baseline: Standard importance-only pruned model (20% sparsity, post-prune 1% GSM8K) recovery via GRPO RLVR. Expected to recover less than RASP counterpart due to non-optimal structure selection.\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T17:37:57.677Z\"}, \"grpo_rasp_20\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-14T17:08:34.784Z\", \"hypothesis\": \"RASP-pruned model (20% sparsity, post-prune 29% GSM8K) recovers better under GRPO RLVR than standard-pruned model (20% sparsity, post-prune 1% GSM8K). Both have identical total MLP params (395,232) — difference is purely from distribution strategy (Scenario B).\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T17:37:57.217Z\"}, \"mvp_rasp_pipeline_v3\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-14T14:00:25.837Z\", \"hypothesis\": \"CKA functional overlap F(h) predicts structured pruning recoverability under RLVR. RASP scoring S(h)=I(h)×(1-F(h))^α selects structures whose removal is more recoverable via GRPO RLVR than standard importance-only pruning. MVP: Spearman ρ(F(h), recoverability) ≥ 0.4 on DeepSeek-R1-Distill-Qwen-7B @ 35% sparsity. V3: Fixed per-layer capacity floor (MLP ≥40% per layer) to prevent early layer collapse.\", \"notes\": \"v3 fix: min_keep_mlp changed from 4 to max(4, int(n_mlp_groups*0.4))=12, ensuring ≥40% MLP capacity per layer. Actual sparsity: Standard=33.02%, RASP=33.21%. MLP range both [8128,18944]. GSM8K@100 results: Standard=0.0% (0/100), RASP=1.0% (1/100). v2 had 0.15% with min_keep_mlp=4. The capacity floor preserved more MLP width but did not rescue reasoning ability. Model outputs remain degenerate (repeated digits, empty strings, repetition loops). 35% structured sparsity fundamentally destroys too much model capacity for this architecture. Next steps: (1) try 20-25% sparsity, (2) add post-prune recovery fine-tuning (the actual RASP hypothesis), or (3) semi-structured pruning.\", \"parent\": \"mvp_rasp_pipeline_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T14:40:41.424Z\"}, \"mvp_rasp_pipeline_v2\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-14T06:08:01.844Z\", \"hypothesis\": \"CKA functional overlap F(h) predicts structured pruning recoverability under RLVR. RASP scoring S(h)=I(h)×(1-F(h))^α selects structures whose removal is more recoverable via GRPO RLVR than standard importance-only pruning. MVP: Spearman ρ(F(h), recoverability) ≥ 0.4 on DeepSeek-R1-Distill-Qwen-7B @ 35% sparsity. V2: GQA group granularity + MLP-level correlation.\", \"notes\": \"根因：prune.py min_keep_mlp=4，每层 28 MLP groups 保留仅 4 组(14.3%)。全局贪心排序导致 early layers (0-6) 被集中剪至 14.3% capacity，摧毁初始表征 → 模型崩溃至 0.15% accuracy。RASP scoring 逻辑本身正常（两模型选了不同结构），但都被剪崩了。GRPO 在退化模型上 loss=0/grad_norm=0，无学习信号。\", \"parent\": \"mvp_rasp_pipeline\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T14:00:06.035Z\"}, \"mvp_rasp_pipeline\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-14T04:10:10.348Z\", \"hypothesis\": \"CKA functional overlap F(h) 预测结构化剪枝后 RLVR recoverability：高 overlap heads 被剪后 RLVR 更容易恢复其功能（通过调整相似 retained heads）。MVP 验证 Spearman ρ(F(h), recoverability) ≥ 0.4。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T05:26:15.414Z\"}}, \"count\": 454, \"total\": 454, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.107}}"
    }
  },
  "sourceToolAssistantUUID": "94fac28f-68b2-492e-9da3-b78315a77ed6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 17_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[CRON] 实验进程异常退出（失败），需要你诊断原因。 详情: Process exited without valid W&B metrics  - exp_id: eval_math500_sft_standard_20_fixed_v3 - project: recovery_aware_struct_prune - server: westd-32935 - log_path: ~/ru…",
  "leafUuid": "9590cf61-6d54-4fe8-adc7-7480aefd274f",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699"
}
```

---

### Runtime record

_source line 18_

```json
{
  "type": "ai-title",
  "aiTitle": "Diagnose W&B metrics missing in failed experiment",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699"
}
```

---

### Tool result

_source line 19 · 2026-05-23T21:17:15.558Z_

<details><summary>↩ Tool result · `toolu_018vcjbr7JFseeE6HBZ78e9K`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"reconciled\": 6, \"results\": [{\"exp_id\": \"eval_math500_grpo_standard_20_fixed\", \"success\": true, \"actions\": [\"Job still running (pid=142477)\"]}, {\"exp_id\": \"eval_math500_sft_standard_20_fixed\", \"success\": true, \"actions\": [\"Stale cron removed (registry status=DONE)\"]}, {\"exp_id\": \"eval_math500_grpo_rasp_alpha1p0_20_fixed\", \"success\": true, \"actions\": [\"Job still running (pid=145167)\"]}, {\"exp_id\": \"eval_math500_grpo_cka_only_20_fixed\", \"success\": true, \"actions\": [\"Job still running (pid=321423)\"]}, {\"exp_id\": \"eval_math500_sft_random_20_fixed_v2\", \"success\": true, \"actions\": [\"Sentinel EXIT_CODE=143 → Registry → DONE(failed)\", \"Cron deleted\"]}, {\"exp_id\": \"eval_math500_sft_standard_25_fixed_v2\", \"success\": true, \"actions\": [\"Job still running (pid=166236)\"]}]}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c8002556-d0ac-4f6b-b948-a435cf9a3b67",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "e61e4b26-ab9a-4ca7-9b96-6f97ff8a2236",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"reconciled\\\": 6, \\\"results\\\": [{\\\"exp_id\\\": \\\"eval_math500_grpo_standard_20_fixed\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=142477)\\\"]}, {\\\"exp_id\\\": \\\"eval_math500_sft_standard_20_fixed\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Stale cron removed (registry status=DONE)\\\"]}, {\\\"exp_id\\\": \\\"eval_math500_grpo_rasp_alpha1p0_20_fixed\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=145167)\\\"]}, {\\\"exp_id\\\": \\\"eval_math500_grpo_cka_only_20_fixed\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=321423)\\\"]}, {\\\"exp_id\\\": \\\"eval_math500_sft_random_20_fixed_v2\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Sentinel EXIT_CODE=143 → Registry → DONE(failed)\\\", \\\"Cron deleted\\\"]}, {\\\"exp_id\\\": \\\"eval_math500_sft_standard_25_fixed_v2\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=166236)\\\"]}]}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"reconciled\": 6, \"results\": [{\"exp_id\": \"eval_math500_grpo_standard_20_fixed\", \"success\": true, \"actions\": [\"Job still running (pid=142477)\"]}, {\"exp_id\": \"eval_math500_sft_standard_20_fixed\", \"success\": true, \"actions\": [\"Stale cron removed (registry status=DONE)\"]}, {\"exp_id\": \"eval_math500_grpo_rasp_alpha1p0_20_fixed\", \"success\": true, \"actions\": [\"Job still running (pid=145167)\"]}, {\"exp_id\": \"eval_math500_grpo_cka_only_20_fixed\", \"success\": true, \"actions\": [\"Job still running (pid=321423)\"]}, {\"exp_id\": \"eval_math500_sft_random_20_fixed_v2\", \"success\": true, \"actions\": [\"Sentinel EXIT_CODE=143 → Registry → DONE(failed)\", \"Cron deleted\"]}, {\"exp_id\": \"eval_math500_sft_standard_25_fixed_v2\", \"success\": true, \"actions\": [\"Job still running (pid=166236)\"]}]}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "c8002556-d0ac-4f6b-b948-a435cf9a3b67",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-23T21:17:15.573Z_

<details><summary>↩ Tool result · `toolu_01JJs5suDw9wbS5uNy9Dg9Xh`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/report.md\", \"content\": \"&lt;!-- AUTO-FACTS-BEGIN (generated 2026-05-23T21:17:05Z; do not edit — regenerated by auto_build_report_facts) -->\\n## 📊 当前状态（auto-derived from registry）\\n\\n**总计**: 454 个实验 — ALLOCATED 3, DONE 404, PREPARING 44, RUNNING 3\\n**DONE 分布**: failed 83, killed 41, negative 23, success 257\\n\\n### GPU 占用\\n- **分配**: 6 张 — westb-23072:cuda:0, westb-23072:cuda:1, westd-32935:cuda:0, westd-32935:cuda:1, westd-32935:cuda:2, westd-32935:cuda:3\\n- **实际运行**: 3 张 — westd-32935:cuda:2(eval_math500_grpo_standard_20_fixed), westd-32935:cuda:1(eval_math500_grpo_rasp_alpha1p0_20_fixed), westb-23072:cuda:0(eval_math500_grpo_cka_only_20_fixed)\\n- **空闲（分配了没跑）**: westb-23072:cuda:1, westd-32935:cuda:0, westd-32935:cuda:3\\n\\n### 💾 磁盘余量\\n- **westb-23072**:\\n  - `/autodl-pub`: 7.4T/14T 可用（已用 48%）\\n  - `/autodl-pub/data`: 18T/20T 可用（已用 9%）\\n  - `/usr/bin/nvidia-smi`: 395G/439G 可用（已用 6%）\\n- **westd-32935**:\\n  - `/autodl-pub`: 5.3T/7.3T 可用（已用 24%）\\n  - `/init`: 150M/150M 可用（已用 0%）\\n  - `/usr/bin/nvidia-smi`: 435G/879G 可用（已用 48%）\\n\\n### 🏃 RUNNING\\n| exp_id | server | gpu | pid | log |\\n|--------|--------|-----|-----|-----|\\n| `eval_math500_grpo_standard_20_fixed` | westd-32935 | cuda:2 | 142477 | `…_aware_struct_prune/eval_math500_grpo_standard_20_fixed.log` |\\n| `eval_math500_grpo_rasp_alpha1p0_20_fixed` | westd-32935 | cuda:1 | 145167 | `…e_struct_prune/eval_math500_grpo_rasp_alpha1p0_20_fixed.log` |\\n| `eval_math500_grpo_cka_only_20_fixed` | westb-23072 | cuda:0 | 321423 | `…_aware_struct_prune/eval_math500_grpo_cka_only_20_fixed.log` |\\n\\n### 📌 最近完成 (top 5)\\n- `eval_math500_sft_standard_25_fixed` [killed] — 2026-05-23T21:11:02\\n- `eval_math500_sft_standard_20_fixed_v2` [killed] — 2026-05-23T21:09:23\\n- `eval_math500_sft_random_20_fixed` [killed] — 2026-05-23T21:05:07\\n- `eval_math500_sft_standard_20_fixed` [failed] — 2026-05-23T20:10:08\\n- `eval_math500_sft_cka_only_20_fixed_v2` [success] — 2026-05-23T19:42:45\\n\\n### 🔴 最近失败原因 (top 3)\\n- `eval_math500_sft_standard_25_fixed`: _(no failure_reason — pre-2026-04-24 entry)_\\n- `eval_math500_sft_standard_20_fixed_v2`: _(no failure_reason — pre-2026-04-24 entry)_\\n- `eval_math500_sft_random_20_fixed`: _(no failure_reason — pre-2026-04-24 entry)_\\n\\n&lt;!-- AUTO-FACTS-END -->\\n\\n---\\n\\n# Handover — 2026-05-23\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| eval_math500_grpo_cka_only_20_fixed | GRPO CKA-only 20% MATH-500 with fixed eval script. Model on westb (grpo_cka_only_20/checkpoint-100). P0 method comparison. | — | — | — |\\n\\n## 待处理\\n- floor_ablation_0p3_cka_only_20: Floor ratio ablation: lowering the MLP floor from 0.4 to 0.3 allows more aggressive pruning of unimportant layers while CKA-only criterion preserves critical structure. If floor=0.3 maintains GSM8K accuracy within 2pp of floor=0.4 baseline, it demonstrates robustness of CKA-guided pruning to floor choice.（已分配 ? GPU:?，等待提交）\\n- floor_ablation_0p5_cka_only_20: Floor ratio ablation: raising the MLP floor from 0.4 to 0.5 constrains pruning to be more conservative. If floor=0.5 improves GSM8K accuracy over floor=0.4, it suggests CKA-only criterion benefits from a higher minimum layer size. Maps the sensitivity curve of floor parameter on recovery quality.（已分配 ? GPU:?，等待提交）\\n- …另有 44 项\\n\\n## 近期结论\\n- **eval_math500_sft_standard_25_fixed** (killed): SFT Standard 25% MATH-500 with fixed eval script. Depends on sft_standard_25_retrain. P1 25% sparsity table.\\n\\n## 趋势\\n成功 257 / 负向 23 / 失败 83 / 共 404\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nwestb-23072: 无 GPU 信息\\nwestd-32935: 空闲 cuda:0, cuda:1, cuda:2, cuda:3\\n\\n## 告警\\n- eval_math500_grpo_rasp_20: 训练失败 — unknown\\n- eval_math500_grpo_rasp_20_v2: 训练失败 — unknown\\n- eval_math500_grpo_rasp_20_v3: 训练失败 — unknown\\n- eval_math500_grpo_standard_20: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20: 已被终止 — unknown\\n- eval_pass_k8_standard_20_grpo_qwen_math: 训练失败 — unknown\\n- eval_postprune_cka_only_30: 已被终止 — unknown\\n- eval_sft_alpha_0p5: 已被终止 — unknown\\n- eval_sft_cka_only_20_full: 训练失败 — unknown\\n- eval_sft_cka_only_20_full_v2: 已被终止 — Superseded by eval_sft_cka_only_20_n1319 which was submitted by fix worker\\n- eval_sft_rasp_20_seed123: 训练失败 — unknown\\n- eval_sft_rasp_20_seed456: 训练失败 — unknown\\n- eval_sft_rasp_qwen_math: 已被终止 — unknown\\n- eval_sft_standard_20_full: 训练失败 — unknown\\n- eval_sft_standard_20_n1319: 训练失败 — unknown\\n- eval_sft_standard_20_seed123: 训练失败 — unknown\\n- eval_sft_standard_20_seed456: 训练失败 — unknown\\n- eval_sft_standard_qwen_math: 已被终止 — unknown\\n- grpo_rasp_20: 已被终止 — unknown\\n- grpo_rasp_20_4096: 训练失败 — unknown\\n- grpo_rasp_qwen_math: 已被终止 — unknown\\n- grpo_rasp_rlvr_20: 训练失败 — unknown\\n- grpo_stage2_rasp_20: 已被终止 — unknown\\n- grpo_stage2_rasp_20_v3: 训练失败 — unknown\\n- grpo_stage2_rasp_20_v4: 已被终止 — unknown\\n- grpo_stage2_rasp_20_v5: 已被终止 — unknown\\n- grpo_stage2_rasp_20_v6: 训练失败 — unknown\\n- grpo_stage2_rasp_20_v7: 训练失败 — unknown\\n- grpo_stage2_standard_20: 已被终止 — unknown\\n- grpo_stage2_standard_20_v2: 训练失败 — unknown\\n- grpo_stage2_standard_20_v6: 训练失败 — unknown\\n- grpo_stage2_standard_20_v7: 训练失败 — unknown\\n- grpo_standard_20: 已被终止 — unknown\\n- grpo_standard_qwen_math: 已被终止 — unknown\\n- grpo_unpruned_baseline: 训练失败 — unknown\\n- inference_bench_full: 训练失败 — unknown\\n- inference_speedup_plan016: 训练失败 — unknown\\n- mvp_rasp_pipeline: 训练失败 — unknown\\n- mvp_rasp_pipeline_v2: 训练失败 — unknown\\n- scoring_ablation_batch_v2: 训练失败 — unknown\\n- scoring_ablation_magnitude_20: 训练失败 — unknown\\n- sft_alpha4_0_westd: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20_v2: 训练失败 — unknown\\n- eval_gsm8k_grpo_cka_only_20: 训练失败 — unknown\\n- inference_bench_cka_only_20: 训练失败 — unknown\\n- eval_math500_grpo_standard_20_fair: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20_v3: 训练失败 — unknown\\n- grpo_standard_20_extended_300: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20_v4: 训练失败 — unknown\\n- eval_math500_sft_standard_20_2048: 已被终止 — unknown\\n- eval_humaneval_grpo_standard_20_fair_2048: 训练失败 — unknown\\n- eval_humaneval_grpo_standard_20_fair_2048_v2: 训练失败 — unknown\\n- eval_humaneval_sft_cka_only_20_2048: 训练失败 — unknown\\n- eval_humaneval_grpo_rasp_20_1p5b_2048: 已被终止 — unknown\\n- eval_humaneval_sft_rasp_20_2048_v3: 已被终止 — unknown\\n- eval_humaneval_sft_standard_20_2048_v4: 已被终止 — unknown\\n- grpo_shortgpt_20: 训练失败 — unknown\\n- eval_mbpp_grpo_standard_20: 训练失败 — unknown\\n- eval_mbpp_sft_standard_20: 训练失败 — unknown\\n- eval_mbpp_sft_standard_20_v3: 训练失败 — unknown\\n- eval_mbpp_sft_standard_20_clean: 训练失败 — unknown\\n- eval_mbpp_sft_shortgpt_20: 训练失败 — unknown\\n- eval_mbpp_grpo_shortgpt_20: 训练失败 — unknown\\n- eval_gsm8k_grpo_standard_20_step50: 已被终止 — unknown\\n- pipeline_cka_only_15: 训练失败 — unknown\\n- pipeline_standard_15: 训练失败 — unknown\\n- qwen_math_7b_feasibility: 训练失败 — unknown\\n- sft_qwen_math_standard_20: 训练失败 — unknown\\n- sft_qwen_math_standard_20_v2: 训练失败 — unknown\\n- grpo_standard_15_seed123: 训练失败 — unknown\\n- grpo_standard_15_seed456: 训练失败 — unknown\\n- grpo_standard_15_seed123_v2: 训练失败 — unknown\\n- grpo_standard_15_seed456_v2: 训练失败 — unknown\\n- eval_gsm8k_grpo_standard_15_seed123: 训练失败 — unknown\\n- eval_gsm8k_grpo_standard_15_seed456: 训练失败 — unknown\\n- grpo_standard_15_seed123_v4: 已被终止 — unknown\\n- grpo_standard_15_seed456_v4: 已被终止 — unknown\\n- eval_gsm8k_grpo_standard_15_seed123_v2: 训练失败 — unknown\\n- eval_gsm8k_grpo_standard_15_seed456_v2: 训练失败 — unknown\\n- eval_gsm8k_grpo_cka_only_25: 训练失败 — unknown\\n- eval_gsm8k_grpo_cka_only_25_v2: 训练失败 — unknown\\n- eval_gsm8k_grpo_random_20: 训练失败 — unknown\\n- eval_math500_sft_standard_25_v2: 训练失败 — unknown\\n- eval_math500_grpo_cka_only_25: 已被终止 — unknown\\n- eval_math500_sft_cka_only_25: 已被终止 — unknown\\n- eval_math500_grpo_random_20: 已被终止 — unknown\\n- eval_math500_grpo_standard_25: 已被终止 — unknown\\n- eval_math500_grpo_cka_only_20_v3: 已被终止 — unknown\\n- eval_math500_sft_random_20: 训练失败 — unknown\\n- pipeline_alpha4_0: 训练失败 — unknown\\n- pipeline_alpha4_0_v2: 训练失败 — unknown\\n- sft_alpha4_20_manual: 训练失败 — unknown\\n- eval_gsm8k_grpo_alpha4_20: 训练失败 — unknown\\n- eval_math500_grpo_alpha4_20: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20_v5: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20_v6: 已被终止 — unknown\\n- eval_gsm8k_sft_alpha4_20: 训练失败 — unknown\\n- eval_gsm8k_sft_alpha4_20_v3: 已被终止 — unknown\\n- eval_math500_grpo_standard_20_fair_2048: 已被终止 — unknown\\n- eval_gsm8k_sft_alpha4_20_v4: 训练失败 — unknown\\n- eval_math500_sft_random_20_v2: 训练失败 — unknown\\n- pipeline_alpha0p5_20: 训练失败 — unknown\\n- pipeline_alpha2p0_20: 训练失败 — unknown\\n- eval_gsm8k_grpo_qwen_math_cka_only_20: 已被终止 — unknown\\n- pipeline_depth_first_20: 训练失败 — unknown\\n- eval_gsm8k_grpo_random_20_seed123: 已被终止 — unknown\\n- eval_gsm8k_grpo_qwen_math_cka_only_20_n500: 已被终止 — unknown\\n- eval_gsm8k_grpo_qwen_math_cka_only_20_n500_v2: 训练失败 — unknown\\n- eval_math500_sft_rasp_alpha1p0_20: 已被终止 — unknown\\n- eval_math500_sft_cka_only_20_westb: 已被终止 — unknown\\n- E_MATH500_SFT_QWEN_CKA: 训练失败 — unknown\\n- eval_gsm8k_sft_qwen_math_cka_only_20_n500: 训练失败 — unknown\\n- floor_ablation_0p6_cka_only_20: 训练失败 — unknown\\n- eval_gsm8k_postprune_cka_only_30_n1319: 已被终止 — unknown\\n- eval_math500_grpo_standard_20_fair_2048_v3: 已被终止 — unknown\\n- eval_math500_grpo_standard_20_fair_2048_v3b: 已被终止 — unknown\\n- eval_math500_sft_cka_only_20_fixed: 训练失败 — unknown\\n- eval_math500_sft_standard_20_fixed: 训练失败 — unknown\\n- grpo_random_20_retrain: 训练失败 — unknown\\n- eval_math500_sft_standard_25_fixed: 已被终止 — unknown\\n- eval_math500_sft_random_20_fixed: 已被终止 — unknown\\n&lt;!-- 已截断：超过 150 行限制，已执行 Pre-compaction Flush -->\\n\", \"total_chars\": 9330, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "226f0f1d-58a1-4b93-991e-9f485c647345",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "eae4fc4d-6518-407f-9523-faa4b4b4ee0a",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/report.md\\\", \\\"content\\\": \\\"&lt;!-- AUTO-FACTS-BEGIN (generated 2026-05-23T21:17:05Z; do not edit — regenerated by auto_build_report_facts) -->\\\\n## 📊 当前状态（auto-derived from registry）\\\\n\\\\n**总计**: 454 个实验 — ALLOCATED 3, DONE 404, PREPARING 44, RUNNING 3\\\\n**DONE 分布**: failed 83, killed 41, negative 23, success 257\\\\n\\\\n### GPU 占用\\\\n- **分配**: 6 张 — westb-23072:cuda:0, westb-23072:cuda:1, westd-32935:cuda:0, westd-32935:cuda:1, westd-32935:cuda:2, westd-32935:cuda:3\\\\n- **实际运行**: 3 张 — westd-32935:cuda:2(eval_math500_grpo_standard_20_fixed), westd-32935:cuda:1(eval_math500_grpo_rasp_alpha1p0_20_fixed), westb-23072:cuda:0(eval_math500_grpo_cka_only_20_fixed)\\\\n- **空闲（分配了没跑）**: westb-23072:cuda:1, westd-32935:cuda:0, westd-32935:cuda:3\\\\n\\\\n### 💾 磁盘余量\\\\n- **westb-23072**:\\\\n  - `/autodl-pub`: 7.4T/14T 可用（已用 48%）\\\\n  - `/autodl-pub/data`: 18T/20T 可用（已用 9%）\\\\n  - `/usr/bin/nvidia-smi`: 395G/439G 可用（已用 6%）\\\\n- **westd-32935**:\\\\n  - `/autodl-pub`: 5.3T/7.3T 可用（已用 24%）\\\\n  - `/init`: 150M/150M 可用（已用 0%）\\\\n  - `/usr/bin/nvidia-smi`: 435G/879G 可用（已用 48%）\\\\n\\\\n### 🏃 RUNNING\\\\n| exp_id | server | gpu | pid | log |\\\\n|--------|--------|-----|-----|-----|\\\\n| `eval_math500_grpo_standard_20_fixed` | westd-32935 | cuda:2 | 142477 | `…_aware_struct_prune/eval_math500_grpo_standard_20_fixed.log` |\\\\n| `eval_math500_grpo_rasp_alpha1p0_20_fixed` | westd-32935 | cuda:1 | 145167 | `…e_struct_prune/eval_math500_grpo_rasp_alpha1p0_20_fixed.log` |\\\\n| `eval_math500_grpo_cka_only_20_fixed` | westb-23072 | cuda:0 | 321423 | `…_aware_struct_prune/eval_math500_grpo_cka_only_20_fixed.log` |\\\\n\\\\n### 📌 最近完成 (top 5)\\\\n- `eval_math500_sft_standard_25_fixed` [killed] — 2026-05-23T21:11:02\\\\n- `eval_math500_sft_standard_20_fixed_v2` [killed] — 2026-05-23T21:09:23\\\\n- `eval_math500_sft_random_20_fixed` [killed] — 2026-05-23T21:05:07\\\\n- `eval_math500_sft_standard_20_fixed` [failed] — 2026-05-23T20:10:08\\\\n- `eval_math500_sft_cka_only_20_fixed_v2` [success] — 2026-05-23T19:42:45\\\\n\\\\n### 🔴 最近失败原因 (top 3)\\\\n- `eval_math500_sft_standard_25_fixed`: _(no failure_reason — pre-2026-04-24 entry)_\\\\n- `eval_math500_sft_standard_20_fixed_v2`: _(no failure_reason — pre-2026-04-24 entry)_\\\\n- `eval_math500_sft_random_20_fixed`: _(no failure_reason — pre-2026-04-24 entry)_\\\\n\\\\n&lt;!-- AUTO-FACTS-END -->\\\\n\\\\n---\\\\n\\\\n# Handover — 2026-05-23\\\\n\\\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\\\n\\\\n## 运行中\\\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\\\n|--------|------|------|---------|-----|\\\\n| eval_math500_grpo_cka_only_20_fixed | GRPO CKA-only 20% MATH-500 with fixed eval script. Model on westb (grpo_cka_only_20/checkpoint-100). P0 method comparison. | — | — | — |\\\\n\\\\n## 待处理\\\\n- floor_ablation_0p3_cka_only_20: Floor ratio ablation: lowering the MLP floor from 0.4 to 0.3 allows more aggressive pruning of unimportant layers while CKA-only criterion preserves critical structure. If floor=0.3 maintains GSM8K accuracy within 2pp of floor=0.4 baseline, it demonstrates robustness of CKA-guided pruning to floor choice.（已分配 ? GPU:?，等待提交）\\\\n- floor_ablation_0p5_cka_only_20: Floor ratio ablation: raising the MLP floor from 0.4 to 0.5 constrains pruning to be more conservative. If floor=0.5 improves GSM8K accuracy over floor=0.4, it suggests CKA-only criterion benefits from a higher minimum layer size. Maps the sensitivity curve of floor parameter on recovery quality.（已分配 ? GPU:?，等待提交）\\\\n- …另有 44 项\\\\n\\\\n## 近期结论\\\\n- **eval_math500_sft_standard_25_fixed** (killed): SFT Standard 25% MATH-500 with fixed eval script. Depends on sft_standard_25_retrain. P1 25% sparsity table.\\\\n\\\\n## 趋势\\\\n成功 257 / 负向 23 / 失败 83 / 共 404\\\\n\\\\n## 下一步\\\\n（无活跃 idea，请通过 ideas.md 添加）\\\\n\\\\n## 资源状态\\\\nwestb-23072: 无 GPU 信息\\\\nwestd-32935: 空闲 cuda:0, cuda:1, cuda:2, cuda:3\\\\n\\\\n## 告警\\\\n- eval_math500_grpo_rasp_20: 训练失败 — unknown\\\\n- eval_math500_grpo_rasp_20_v2: 训练失败 — unknown\\\\n- eval_math500_grpo_rasp_20_v3: 训练失败 — unknown\\\\n- eval_math500_grpo_standard_20: 训练失败 — unknown\\\\n- eval_math500_sft_cka_only_20: 已被终止 — unknown\\\\n- eval_pass_k8_standard_20_grpo_qwen_math: 训练失败 — unknown\\\\n- eval_postprune_cka_only_30: 已被终止 — unknown\\\\n- eval_sft_alpha_0p5: 已被终止 — unknown\\\\n- eval_sft_cka_only_20_full: 训练失败 — unknown\\\\n- eval_sft_cka_only_20_full_v2: 已被终止 — Superseded by eval_sft_cka_only_20_n1319 which was submitted by fix worker\\\\n- eval_sft_rasp_20_seed123: 训练失败 — unknown\\\\n- eval_sft_rasp_20_seed456: 训练失败 — unknown\\\\n- eval_sft_rasp_qwen_math: 已被终止 — unknown\\\\n- eval_sft_standard_20_full: 训练失败 — unknown\\\\n- eval_sft_standard_20_n1319: 训练失败 — unknown\\\\n- eval_sft_standard_20_seed123: 训练失败 — unknown\\\\n- eval_sft_standard_20_seed456: 训练失败 — unknown\\\\n- eval_sft_standard_qwen_math: 已被终止 — unknown\\\\n- grpo_rasp_20: 已被终止 — unknown\\\\n- grpo_rasp_20_4096: 训练失败 — unknown\\\\n- grpo_rasp_qwen_math: 已被终止 — unknown\\\\n- grpo_rasp_rlvr_20: 训练失败 — unknown\\\\n- grpo_stage2_rasp_20: 已被终止 — unknown\\\\n- grpo_stage2_rasp_20_v3: 训练失败 — unknown\\\\n- grpo_stage2_rasp_20_v4: 已被终止 — unknown\\\\n- grpo_stage2_rasp_20_v5: 已被终止 — unknown\\\\n- grpo_stage2_rasp_20_v6: 训练失败 — unknown\\\\n- grpo_stage2_rasp_20_v7: 训练失败 — unknown\\\\n- grpo_stage2_standard_20: 已被终止 — unknown\\\\n- grpo_stage2_standard_20_v2: 训练失败 — unknown\\\\n- grpo_stage2_standard_20_v6: 训练失败 — unknown\\\\n- grpo_stage2_standard_20_v7: 训练失败 — unknown\\\\n- grpo_standard_20: 已被终止 — unknown\\\\n- grpo_standard_qwen_math: 已被终止 — unknown\\\\n- grpo_unpruned_baseline: 训练失败 — unknown\\\\n- inference_bench_full: 训练失败 — unknown\\\\n- inference_speedup_plan016: 训练失败 — unknown\\\\n- mvp_rasp_pipeline: 训练失败 — unknown\\\\n- mvp_rasp_pipeline_v2: 训练失败 — unknown\\\\n- scoring_ablation_batch_v2: 训练失败 — unknown\\\\n- scoring_ablation_magnitude_20: 训练失败 — unknown\\\\n- sft_alpha4_0_westd: 训练失败 — unknown\\\\n- eval_math500_sft_cka_only_20_v2: 训练失败 — unknown\\\\n- eval_gsm8k_grpo_cka_only_20: 训练失败 — unknown\\\\n- inference_bench_cka_only_20: 训练失败 — unknown\\\\n- eval_math500_grpo_standard_20_fair: 训练失败 — unknown\\\\n- eval_math500_sft_cka_only_20_v3: 训练失败 — unknown\\\\n- grpo_standard_20_extended_300: 训练失败 — unknown\\\\n- eval_math500_sft_cka_only_20_v4: 训练失败 — unknown\\\\n- eval_math500_sft_standard_20_2048: 已被终止 — unknown\\\\n- eval_humaneval_grpo_standard_20_fair_2048: 训练失败 — unknown\\\\n- eval_humaneval_grpo_standard_20_fair_2048_v2: 训练失败 — unknown\\\\n- eval_humaneval_sft_cka_only_20_2048: 训练失败 — unknown\\\\n- eval_humaneval_grpo_rasp_20_1p5b_2048: 已被终止 — unknown\\\\n- eval_humaneval_sft_rasp_20_2048_v3: 已被终止 — unknown\\\\n- eval_humaneval_sft_standard_20_2048_v4: 已被终止 — unknown\\\\n- grpo_shortgpt_20: 训练失败 — unknown\\\\n- eval_mbpp_grpo_standard_20: 训练失败 — unknown\\\\n- eval_mbpp_sft_standard_20: 训练失败 — unknown\\\\n- eval_mbpp_sft_standard_20_v3: 训练失败 — unknown\\\\n- eval_mbpp_sft_standard_20_clean: 训练失败 — unknown\\\\n- eval_mbpp_sft_shortgpt_20: 训练失败 — unknown\\\\n- eval_mbpp_grpo_shortgpt_20: 训练失败 — unknown\\\\n- eval_gsm8k_grpo_standard_20_step50: 已被终止 — unknown\\\\n- pipeline_cka_only_15: 训练失败 — unknown\\\\n- pipeline_standard_15: 训练失败 — unknown\\\\n- qwen_math_7b_feasibility: 训练失败 — unknown\\\\n- sft_qwen_math_standard_20: 训练失败 — unknown\\\\n- sft_qwen_math_standard_20_v2: 训练失败 — unknown\\\\n- grpo_standard_15_seed123: 训练失败 — unknown\\\\n- grpo_standard_15_seed456: 训练失败 — unknown\\\\n- grpo_standard_15_seed123_v2: 训练失败 — unknown\\\\n- grpo_standard_15_seed456_v2: 训练失败 — unknown\\\\n- eval_gsm8k_grpo_standard_15_seed123: 训练失败 — unknown\\\\n- eval_gsm8k_grpo_standard_15_seed456: 训练失败 — unknown\\\\n- grpo_standard_15_seed123_v4: 已被终止 — unknown\\\\n- grpo_standard_15_seed456_v4: 已被终止 — unknown\\\\n- eval_gsm8k_grpo_standard_15_seed123_v2: 训练失败 — unknown\\\\n- eval_gsm8k_grpo_standard_15_seed456_v2: 训练失败 — unknown\\\\n- eval_gsm8k_grpo_cka_only_25: 训练失败 — unknown\\\\n- eval_gsm8k_grpo_cka_only_25_v2: 训练失败 — unknown\\\\n- eval_gsm8k_grpo_random_20: 训练失败 — unknown\\\\n- eval_math500_sft_standard_25_v2: 训练失败 — unknown\\\\n- eval_math500_grpo_cka_only_25: 已被终止 — unknown\\\\n- eval_math500_sft_cka_only_25: 已被终止 — unknown\\\\n- eval_math500_grpo_random_20: 已被终止 — unknown\\\\n- eval_math500_grpo_standard_25: 已被终止 — unknown\\\\n- eval_math500_grpo_cka_only_20_v3: 已被终止 — unknown\\\\n- eval_math500_sft_random_20: 训练失败 — unknown\\\\n- pipeline_alpha4_0: 训练失败 — unknown\\\\n- pipeline_alpha4_0_v2: 训练失败 — unknown\\\\n- sft_alpha4_20_manual: 训练失败 — unknown\\\\n- eval_gsm8k_grpo_alpha4_20: 训练失败 — unknown\\\\n- eval_math500_grpo_alpha4_20: 训练失败 — unknown\\\\n- eval_math500_sft_cka_only_20_v5: 训练失败 — unknown\\\\n- eval_math500_sft_cka_only_20_v6: 已被终止 — unknown\\\\n- eval_gsm8k_sft_alpha4_20: 训练失败 — unknown\\\\n- eval_gsm8k_sft_alpha4_20_v3: 已被终止 — unknown\\\\n- eval_math500_grpo_standard_20_fair_2048: 已被终止 — unknown\\\\n- eval_gsm8k_sft_alpha4_20_v4: 训练失败 — unknown\\\\n- eval_math500_sft_random_20_v2: 训练失败 — unknown\\\\n- pipeline_alpha0p5_20: 训练失败 — unknown\\\\n- pipeline_alpha2p0_20: 训练失败 — unknown\\\\n- eval_gsm8k_grpo_qwen_math_cka_only_20: 已被终止 — unknown\\\\n- pipeline_depth_first_20: 训练失败 — unknown\\\\n- eval_gsm8k_grpo_random_20_seed123: 已被终止 — unknown\\\\n- eval_gsm8k_grpo_qwen_math_cka_only_20_n500: 已被终止 — unknown\\\\n- eval_gsm8k_grpo_qwen_math_cka_only_20_n500_v2: 训练失败 — unknown\\\\n- eval_math500_sft_rasp_alpha1p0_20: 已被终止 — unknown\\\\n- eval_math500_sft_cka_only_20_westb: 已被终止 — unknown\\\\n- E_MATH500_SFT_QWEN_CKA: 训练失败 — unknown\\\\n- eval_gsm8k_sft_qwen_math_cka_only_20_n500: 训练失败 — unknown\\\\n- floor_ablation_0p6_cka_only_20: 训练失败 — unknown\\\\n- eval_gsm8k_postprune_cka_only_30_n1319: 已被终止 — unknown\\\\n- eval_math500_grpo_standard_20_fair_2048_v3: 已被终止 — unknown\\\\n- eval_math500_grpo_standard_20_fair_2048_v3b: 已被终止 — unknown\\\\n- eval_math500_sft_cka_only_20_fixed: 训练失败 — unknown\\\\n- eval_math500_sft_standard_20_fixed: 训练失败 — unknown\\\\n- grpo_random_20_retrain: 训练失败 — unknown\\\\n- eval_math500_sft_standard_25_fixed: 已被终止 — unknown\\\\n- eval_math500_sft_random_20_fixed: 已被终止 — unknown\\\\n&lt;!-- 已截断：超过 150 行限制，已执行 Pre-compaction Flush -->\\\\n\\\", \\\"total_chars\\\": 9330, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/report.md\", \"content\": \"&lt;!-- AUTO-FACTS-BEGIN (generated 2026-05-23T21:17:05Z; do not edit — regenerated by auto_build_report_facts) -->\\n## 📊 当前状态（auto-derived from registry）\\n\\n**总计**: 454 个实验 — ALLOCATED 3, DONE 404, PREPARING 44, RUNNING 3\\n**DONE 分布**: failed 83, killed 41, negative 23, success 257\\n\\n### GPU 占用\\n- **分配**: 6 张 — westb-23072:cuda:0, westb-23072:cuda:1, westd-32935:cuda:0, westd-32935:cuda:1, westd-32935:cuda:2, westd-32935:cuda:3\\n- **实际运行**: 3 张 — westd-32935:cuda:2(eval_math500_grpo_standard_20_fixed), westd-32935:cuda:1(eval_math500_grpo_rasp_alpha1p0_20_fixed), westb-23072:cuda:0(eval_math500_grpo_cka_only_20_fixed)\\n- **空闲（分配了没跑）**: westb-23072:cuda:1, westd-32935:cuda:0, westd-32935:cuda:3\\n\\n### 💾 磁盘余量\\n- **westb-23072**:\\n  - `/autodl-pub`: 7.4T/14T 可用（已用 48%）\\n  - `/autodl-pub/data`: 18T/20T 可用（已用 9%）\\n  - `/usr/bin/nvidia-smi`: 395G/439G 可用（已用 6%）\\n- **westd-32935**:\\n  - `/autodl-pub`: 5.3T/7.3T 可用（已用 24%）\\n  - `/init`: 150M/150M 可用（已用 0%）\\n  - `/usr/bin/nvidia-smi`: 435G/879G 可用（已用 48%）\\n\\n### 🏃 RUNNING\\n| exp_id | server | gpu | pid | log |\\n|--------|--------|-----|-----|-----|\\n| `eval_math500_grpo_standard_20_fixed` | westd-32935 | cuda:2 | 142477 | `…_aware_struct_prune/eval_math500_grpo_standard_20_fixed.log` |\\n| `eval_math500_grpo_rasp_alpha1p0_20_fixed` | westd-32935 | cuda:1 | 145167 | `…e_struct_prune/eval_math500_grpo_rasp_alpha1p0_20_fixed.log` |\\n| `eval_math500_grpo_cka_only_20_fixed` | westb-23072 | cuda:0 | 321423 | `…_aware_struct_prune/eval_math500_grpo_cka_only_20_fixed.log` |\\n\\n### 📌 最近完成 (top 5)\\n- `eval_math500_sft_standard_25_fixed` [killed] — 2026-05-23T21:11:02\\n- `eval_math500_sft_standard_20_fixed_v2` [killed] — 2026-05-23T21:09:23\\n- `eval_math500_sft_random_20_fixed` [killed] — 2026-05-23T21:05:07\\n- `eval_math500_sft_standard_20_fixed` [failed] — 2026-05-23T20:10:08\\n- `eval_math500_sft_cka_only_20_fixed_v2` [success] — 2026-05-23T19:42:45\\n\\n### 🔴 最近失败原因 (top 3)\\n- `eval_math500_sft_standard_25_fixed`: _(no failure_reason — pre-2026-04-24 entry)_\\n- `eval_math500_sft_standard_20_fixed_v2`: _(no failure_reason — pre-2026-04-24 entry)_\\n- `eval_math500_sft_random_20_fixed`: _(no failure_reason — pre-2026-04-24 entry)_\\n\\n&lt;!-- AUTO-FACTS-END -->\\n\\n---\\n\\n# Handover — 2026-05-23\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| eval_math500_grpo_cka_only_20_fixed | GRPO CKA-only 20% MATH-500 with fixed eval script. Model on westb (grpo_cka_only_20/checkpoint-100). P0 method comparison. | — | — | — |\\n\\n## 待处理\\n- floor_ablation_0p3_cka_only_20: Floor ratio ablation: lowering the MLP floor from 0.4 to 0.3 allows more aggressive pruning of unimportant layers while CKA-only criterion preserves critical structure. If floor=0.3 maintains GSM8K accuracy within 2pp of floor=0.4 baseline, it demonstrates robustness of CKA-guided pruning to floor choice.（已分配 ? GPU:?，等待提交）\\n- floor_ablation_0p5_cka_only_20: Floor ratio ablation: raising the MLP floor from 0.4 to 0.5 constrains pruning to be more conservative. If floor=0.5 improves GSM8K accuracy over floor=0.4, it suggests CKA-only criterion benefits from a higher minimum layer size. Maps the sensitivity curve of floor parameter on recovery quality.（已分配 ? GPU:?，等待提交）\\n- …另有 44 项\\n\\n## 近期结论\\n- **eval_math500_sft_standard_25_fixed** (killed): SFT Standard 25% MATH-500 with fixed eval script. Depends on sft_standard_25_retrain. P1 25% sparsity table.\\n\\n## 趋势\\n成功 257 / 负向 23 / 失败 83 / 共 404\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nwestb-23072: 无 GPU 信息\\nwestd-32935: 空闲 cuda:0, cuda:1, cuda:2, cuda:3\\n\\n## 告警\\n- eval_math500_grpo_rasp_20: 训练失败 — unknown\\n- eval_math500_grpo_rasp_20_v2: 训练失败 — unknown\\n- eval_math500_grpo_rasp_20_v3: 训练失败 — unknown\\n- eval_math500_grpo_standard_20: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20: 已被终止 — unknown\\n- eval_pass_k8_standard_20_grpo_qwen_math: 训练失败 — unknown\\n- eval_postprune_cka_only_30: 已被终止 — unknown\\n- eval_sft_alpha_0p5: 已被终止 — unknown\\n- eval_sft_cka_only_20_full: 训练失败 — unknown\\n- eval_sft_cka_only_20_full_v2: 已被终止 — Superseded by eval_sft_cka_only_20_n1319 which was submitted by fix worker\\n- eval_sft_rasp_20_seed123: 训练失败 — unknown\\n- eval_sft_rasp_20_seed456: 训练失败 — unknown\\n- eval_sft_rasp_qwen_math: 已被终止 — unknown\\n- eval_sft_standard_20_full: 训练失败 — unknown\\n- eval_sft_standard_20_n1319: 训练失败 — unknown\\n- eval_sft_standard_20_seed123: 训练失败 — unknown\\n- eval_sft_standard_20_seed456: 训练失败 — unknown\\n- eval_sft_standard_qwen_math: 已被终止 — unknown\\n- grpo_rasp_20: 已被终止 — unknown\\n- grpo_rasp_20_4096: 训练失败 — unknown\\n- grpo_rasp_qwen_math: 已被终止 — unknown\\n- grpo_rasp_rlvr_20: 训练失败 — unknown\\n- grpo_stage2_rasp_20: 已被终止 — unknown\\n- grpo_stage2_rasp_20_v3: 训练失败 — unknown\\n- grpo_stage2_rasp_20_v4: 已被终止 — unknown\\n- grpo_stage2_rasp_20_v5: 已被终止 — unknown\\n- grpo_stage2_rasp_20_v6: 训练失败 — unknown\\n- grpo_stage2_rasp_20_v7: 训练失败 — unknown\\n- grpo_stage2_standard_20: 已被终止 — unknown\\n- grpo_stage2_standard_20_v2: 训练失败 — unknown\\n- grpo_stage2_standard_20_v6: 训练失败 — unknown\\n- grpo_stage2_standard_20_v7: 训练失败 — unknown\\n- grpo_standard_20: 已被终止 — unknown\\n- grpo_standard_qwen_math: 已被终止 — unknown\\n- grpo_unpruned_baseline: 训练失败 — unknown\\n- inference_bench_full: 训练失败 — unknown\\n- inference_speedup_plan016: 训练失败 — unknown\\n- mvp_rasp_pipeline: 训练失败 — unknown\\n- mvp_rasp_pipeline_v2: 训练失败 — unknown\\n- scoring_ablation_batch_v2: 训练失败 — unknown\\n- scoring_ablation_magnitude_20: 训练失败 — unknown\\n- sft_alpha4_0_westd: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20_v2: 训练失败 — unknown\\n- eval_gsm8k_grpo_cka_only_20: 训练失败 — unknown\\n- inference_bench_cka_only_20: 训练失败 — unknown\\n- eval_math500_grpo_standard_20_fair: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20_v3: 训练失败 — unknown\\n- grpo_standard_20_extended_300: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20_v4: 训练失败 — unknown\\n- eval_math500_sft_standard_20_2048: 已被终止 — unknown\\n- eval_humaneval_grpo_standard_20_fair_2048: 训练失败 — unknown\\n- eval_humaneval_grpo_standard_20_fair_2048_v2: 训练失败 — unknown\\n- eval_humaneval_sft_cka_only_20_2048: 训练失败 — unknown\\n- eval_humaneval_grpo_rasp_20_1p5b_2048: 已被终止 — unknown\\n- eval_humaneval_sft_rasp_20_2048_v3: 已被终止 — unknown\\n- eval_humaneval_sft_standard_20_2048_v4: 已被终止 — unknown\\n- grpo_shortgpt_20: 训练失败 — unknown\\n- eval_mbpp_grpo_standard_20: 训练失败 — unknown\\n- eval_mbpp_sft_standard_20: 训练失败 — unknown\\n- eval_mbpp_sft_standard_20_v3: 训练失败 — unknown\\n- eval_mbpp_sft_standard_20_clean: 训练失败 — unknown\\n- eval_mbpp_sft_shortgpt_20: 训练失败 — unknown\\n- eval_mbpp_grpo_shortgpt_20: 训练失败 — unknown\\n- eval_gsm8k_grpo_standard_20_step50: 已被终止 — unknown\\n- pipeline_cka_only_15: 训练失败 — unknown\\n- pipeline_standard_15: 训练失败 — unknown\\n- qwen_math_7b_feasibility: 训练失败 — unknown\\n- sft_qwen_math_standard_20: 训练失败 — unknown\\n- sft_qwen_math_standard_20_v2: 训练失败 — unknown\\n- grpo_standard_15_seed123: 训练失败 — unknown\\n- grpo_standard_15_seed456: 训练失败 — unknown\\n- grpo_standard_15_seed123_v2: 训练失败 — unknown\\n- grpo_standard_15_seed456_v2: 训练失败 — unknown\\n- eval_gsm8k_grpo_standard_15_seed123: 训练失败 — unknown\\n- eval_gsm8k_grpo_standard_15_seed456: 训练失败 — unknown\\n- grpo_standard_15_seed123_v4: 已被终止 — unknown\\n- grpo_standard_15_seed456_v4: 已被终止 — unknown\\n- eval_gsm8k_grpo_standard_15_seed123_v2: 训练失败 — unknown\\n- eval_gsm8k_grpo_standard_15_seed456_v2: 训练失败 — unknown\\n- eval_gsm8k_grpo_cka_only_25: 训练失败 — unknown\\n- eval_gsm8k_grpo_cka_only_25_v2: 训练失败 — unknown\\n- eval_gsm8k_grpo_random_20: 训练失败 — unknown\\n- eval_math500_sft_standard_25_v2: 训练失败 — unknown\\n- eval_math500_grpo_cka_only_25: 已被终止 — unknown\\n- eval_math500_sft_cka_only_25: 已被终止 — unknown\\n- eval_math500_grpo_random_20: 已被终止 — unknown\\n- eval_math500_grpo_standard_25: 已被终止 — unknown\\n- eval_math500_grpo_cka_only_20_v3: 已被终止 — unknown\\n- eval_math500_sft_random_20: 训练失败 — unknown\\n- pipeline_alpha4_0: 训练失败 — unknown\\n- pipeline_alpha4_0_v2: 训练失败 — unknown\\n- sft_alpha4_20_manual: 训练失败 — unknown\\n- eval_gsm8k_grpo_alpha4_20: 训练失败 — unknown\\n- eval_math500_grpo_alpha4_20: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20_v5: 训练失败 — unknown\\n- eval_math500_sft_cka_only_20_v6: 已被终止 — unknown\\n- eval_gsm8k_sft_alpha4_20: 训练失败 — unknown\\n- eval_gsm8k_sft_alpha4_20_v3: 已被终止 — unknown\\n- eval_math500_grpo_standard_20_fair_2048: 已被终止 — unknown\\n- eval_gsm8k_sft_alpha4_20_v4: 训练失败 — unknown\\n- eval_math500_sft_random_20_v2: 训练失败 — unknown\\n- pipeline_alpha0p5_20: 训练失败 — unknown\\n- pipeline_alpha2p0_20: 训练失败 — unknown\\n- eval_gsm8k_grpo_qwen_math_cka_only_20: 已被终止 — unknown\\n- pipeline_depth_first_20: 训练失败 — unknown\\n- eval_gsm8k_grpo_random_20_seed123: 已被终止 — unknown\\n- eval_gsm8k_grpo_qwen_math_cka_only_20_n500: 已被终止 — unknown\\n- eval_gsm8k_grpo_qwen_math_cka_only_20_n500_v2: 训练失败 — unknown\\n- eval_math500_sft_rasp_alpha1p0_20: 已被终止 — unknown\\n- eval_math500_sft_cka_only_20_westb: 已被终止 — unknown\\n- E_MATH500_SFT_QWEN_CKA: 训练失败 — unknown\\n- eval_gsm8k_sft_qwen_math_cka_only_20_n500: 训练失败 — unknown\\n- floor_ablation_0p6_cka_only_20: 训练失败 — unknown\\n- eval_gsm8k_postprune_cka_only_30_n1319: 已被终止 — unknown\\n- eval_math500_grpo_standard_20_fair_2048_v3: 已被终止 — unknown\\n- eval_math500_grpo_standard_20_fair_2048_v3b: 已被终止 — unknown\\n- eval_math500_sft_cka_only_20_fixed: 训练失败 — unknown\\n- eval_math500_sft_standard_20_fixed: 训练失败 — unknown\\n- grpo_random_20_retrain: 训练失败 — unknown\\n- eval_math500_sft_standard_25_fixed: 已被终止 — unknown\\n- eval_math500_sft_random_20_fixed: 已被终止 — unknown\\n&lt;!-- 已截断：超过 150 行限制，已执行 Pre-compaction Flush -->\\n\", \"total_chars\": 9330, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "226f0f1d-58a1-4b93-991e-9f485c647345",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-23T21:17:15.595Z_

<details><summary>↩ Tool result · `toolu_01Hi1FiLe3WgPB9wKyBZLwZf`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/ROADMAP.md\", \"content\": \"# recovery_aware_struct_prune — Research Dashboard\\n\\n> 最后更新: 2026-05-23 20:05 UTC | 更新原因: Loop #21 全面刷新：MATH-500 fixed eval 唯一 blocking 项，已完成任务标记，stale GPU 状态修正\\n\\n## 核心方向\\nPruning criterion shapes recovery capacity — CKA-only >> Standard in reward (4.4×) and accuracy (4.55pp). Reward-accuracy decoupling: SFT ≈ GRPO accuracy despite vastly different rewards. 详见 paper_framing.md.\\n\\n## 当前阶段: 提交收尾 — DDL 5/25 (~27h)\\n\\n### 唯一 Blocking 项：MATH-500 Fixed Eval\\nD114 决定：旧 eval 脚本有 expression extraction + space normalization bug，全部 19 个 MATH-500 数据点需用 fixed script 重跑。\\n\\n**已完成 (2/19)**：\\n| Eval | Fixed Acc |\\n|------|-----------|\\n| sft_cka_only_20 | 27.4% (was 26.8%) |\\n| sft_rasp_alpha1p0_20 | 21.6% (was 21.2%) |\\n\\n**Running (6)**：Reviewer 19:52 UTC 确认全部健康，GPU 97-99%\\n- westd:0 — eval_math500_sft_standard_25_fixed (~6h)\\n- westd:1 — eval_math500_grpo_rasp_alpha1p0_20_fixed (~2h)\\n- westd:2 — eval_math500_grpo_standard_20_fixed (~2.5h)\\n- westd:3 — eval_math500_sft_standard_20_fixed (~2.5h)\\n- westb:0 — eval_math500_grpo_cka_only_20_fixed (~6h)\\n- westb:1 — eval_math500_sft_random_20_fixed (~6h)\\n\\n**待启动 (~11)**：dose-response α=0.5/2.0/3.0/4.0 × SFT/GRPO (8) + grpo_random_20 (需 checkpoint) + cka_only_25 SFT/GRPO (2)\\n- 25% Standard GRPO → '--'（checkpoint 丢失，不重训）\\n\\n### 已完成的论文修复\\n- [x] Floor ablation 附录表 (0.3=65.05, 0.4=64.37, 0.5=61.71, 0.6=62.02)\\n- [x] 数据完整性审计 ✅（4 处修复）\\n- [x] 匿名仓库 ✅（65 files, c9a2a2b）\\n- [x] Paper Banana → matplotlib 替代完成\\n- [x] C1 scope 全文一致性修复\\n- [x] 4 篇新引用验证\\n- [x] Conclusion 扩充\\n- [x] GRPO 超参审计 + 措辞修正\\n- [x] 论文编译正常（0 critical warnings, 15 pages）\\n\\n### 等 fixed eval 完成后\\n- [ ] 一次性更新 tab_math500.tex 全部数值\\n- [ ] 更新 experiments.tex:85 + appendix.tex:110 inline MATH-500 数值\\n- [ ] 修复 check_paper_consistency warning: 4.62pp 仅在 conclusion（可选）\\n- [ ] paper_compile_and_check + check_paper_consistency\\n- [ ] submit_paper_to_review 最终审查\\n- [ ] 最终提交\\n\\n### Review Issues 状态\\n- Round 1-3: 23/23 resolved ✅\\n- Round 5-6 remaining criticals (in_progress, rebuttal 准备):\\n  - R5-N1: GRPO narrative (dual-layer reframe)\\n  - R5-N2: Cross-arch GRPO (1.5B 数据已有)\\n  - R5-W2: CKA 因果机制 (correlational)\\n  - R6-N1: 单基准\\n  - R6-N2: depth confound\\n\\n## 服务器状态\\n- westd-32935：4× RTX PRO 6000 — 6 个 MATH-500 eval 在跑中\\n- westb-23072：2× RTX PRO 6000 — 2 个 MATH-500 eval 在跑中\\n\\n## 投稿目标\\n- EMNLP 2026 Main (ARR May 25) — **~27h**\\n\\n## GPU 预算\\n- westd-32935: 4× RTX PRO 6000（全部在用）\\n- westb-23072: 2× RTX PRO 6000（全部在用）\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 | 关联实验 |\\n|----|------|------|----------|\\n| D114 | 2026-05-23 | Fix MATH-500 eval script bugs and rerun all method | eval_math500_sft_standard_20_2048_v3, eval_math500_grpo_standard_20_fair_2048_v3b |\\n| D113 | 2026-05-23 | Floor ablation table 改为 GRPO-only 格式；放弃 SFT eval 和 | floor_ablation_0p3_cka_only_20_v2, floor_ablation_0p5_cka_only_20_v2 |\\n| D112 | 2026-05-22 | D112: C1 max |Δ| 修正为 1.34pp（含 MBPP），D111 的 1.14pp  | — |\\n| D111 | 2026-05-22 | C1 quantified upgrade to \\\"universal accuracy-rewar | — |\\n| D110 | 2026-05-22 | depth-first baseline放appendix作为sanity check，不进主表；c | eval_gsm8k_sft_depth_first_20, eval_gsm8k_grpo_depth_first_20 |\\n| D109 | 2026-05-22 | Dose-response narrative 修正：纯 inverted-U，α=2.0 无争议  | eval_gsm8k_grpo_rasp_alpha3p0_20_v2 |\\n| D108 | 2026-05-22 | Dose-response narrative: α=2.0 optimal 为主 claim，GR | eval_gsm8k_sft_alpha3p0_20, eval_gsm8k_grpo_rasp_alpha3p0_20_v2 |\\n| D107 | 2026-05-22 | D107: α=1.0 数据点修正——55.19%/54.43% 无 registry 溯源，替换为 | eval_gsm8k_sft_rasp_20, eval_gsm8k_grpo_rasp_20_fair, eval_gsm8k_grpo_alpha2p0_20 |\\n| D106 | 2026-05-22 | D106: α dose-response 揭示非单调 U 型曲线，α=2.0 (66.11%) 超 | eval_gsm8k_grpo_alpha0p5_20, eval_gsm8k_grpo_alpha4_20_v3, eval_gsm8k_grpo_alpha2p0_20 |\\n| D105 | 2026-05-22 | D105: MF3 Qwen-Math GRPO 启动前修复 prompt 格式——chat tem | sft_qwen_math_cka_only_20, grpo_qwen_math_cka_only_20 |\\n\\n\\n\", \"lines\": 85}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6064fb4c-bb7c-40c4-9ecb-73ae01d095fe",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "2c03b304-6ba4-495c-b992-3d30398f32b2",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/ROADMAP.md\\\", \\\"content\\\": \\\"# recovery_aware_struct_prune — Research Dashboard\\\\n\\\\n> 最后更新: 2026-05-23 20:05 UTC | 更新原因: Loop #21 全面刷新：MATH-500 fixed eval 唯一 blocking 项，已完成任务标记，stale GPU 状态修正\\\\n\\\\n## 核心方向\\\\nPruning criterion shapes recovery capacity — CKA-only >> Standard in reward (4.4×) and accuracy (4.55pp). Reward-accuracy decoupling: SFT ≈ GRPO accuracy despite vastly different rewards. 详见 paper_framing.md.\\\\n\\\\n## 当前阶段: 提交收尾 — DDL 5/25 (~27h)\\\\n\\\\n### 唯一 Blocking 项：MATH-500 Fixed Eval\\\\nD114 决定：旧 eval 脚本有 expression extraction + space normalization bug，全部 19 个 MATH-500 数据点需用 fixed script 重跑。\\\\n\\\\n**已完成 (2/19)**：\\\\n| Eval | Fixed Acc |\\\\n|------|-----------|\\\\n| sft_cka_only_20 | 27.4% (was 26.8%) |\\\\n| sft_rasp_alpha1p0_20 | 21.6% (was 21.2%) |\\\\n\\\\n**Running (6)**：Reviewer 19:52 UTC 确认全部健康，GPU 97-99%\\\\n- westd:0 — eval_math500_sft_standard_25_fixed (~6h)\\\\n- westd:1 — eval_math500_grpo_rasp_alpha1p0_20_fixed (~2h)\\\\n- westd:2 — eval_math500_grpo_standard_20_fixed (~2.5h)\\\\n- westd:3 — eval_math500_sft_standard_20_fixed (~2.5h)\\\\n- westb:0 — eval_math500_grpo_cka_only_20_fixed (~6h)\\\\n- westb:1 — eval_math500_sft_random_20_fixed (~6h)\\\\n\\\\n**待启动 (~11)**：dose-response α=0.5/2.0/3.0/4.0 × SFT/GRPO (8) + grpo_random_20 (需 checkpoint) + cka_only_25 SFT/GRPO (2)\\\\n- 25% Standard GRPO → '--'（checkpoint 丢失，不重训）\\\\n\\\\n### 已完成的论文修复\\\\n- [x] Floor ablation 附录表 (0.3=65.05, 0.4=64.37, 0.5=61.71, 0.6=62.02)\\\\n- [x] 数据完整性审计 ✅（4 处修复）\\\\n- [x] 匿名仓库 ✅（65 files, c9a2a2b）\\\\n- [x] Paper Banana → matplotlib 替代完成\\\\n- [x] C1 scope 全文一致性修复\\\\n- [x] 4 篇新引用验证\\\\n- [x] Conclusion 扩充\\\\n- [x] GRPO 超参审计 + 措辞修正\\\\n- [x] 论文编译正常（0 critical warnings, 15 pages）\\\\n\\\\n### 等 fixed eval 完成后\\\\n- [ ] 一次性更新 tab_math500.tex 全部数值\\\\n- [ ] 更新 experiments.tex:85 + appendix.tex:110 inline MATH-500 数值\\\\n- [ ] 修复 check_paper_consistency warning: 4.62pp 仅在 conclusion（可选）\\\\n- [ ] paper_compile_and_check + check_paper_consistency\\\\n- [ ] submit_paper_to_review 最终审查\\\\n- [ ] 最终提交\\\\n\\\\n### Review Issues 状态\\\\n- Round 1-3: 23/23 resolved ✅\\\\n- Round 5-6 remaining criticals (in_progress, rebuttal 准备):\\\\n  - R5-N1: GRPO narrative (dual-layer reframe)\\\\n  - R5-N2: Cross-arch GRPO (1.5B 数据已有)\\\\n  - R5-W2: CKA 因果机制 (correlational)\\\\n  - R6-N1: 单基准\\\\n  - R6-N2: depth confound\\\\n\\\\n## 服务器状态\\\\n- westd-32935：4× RTX PRO 6000 — 6 个 MATH-500 eval 在跑中\\\\n- westb-23072：2× RTX PRO 6000 — 2 个 MATH-500 eval 在跑中\\\\n\\\\n## 投稿目标\\\\n- EMNLP 2026 Main (ARR May 25) — **~27h**\\\\n\\\\n## GPU 预算\\\\n- westd-32935: 4× RTX PRO 6000（全部在用）\\\\n- westb-23072: 2× RTX PRO 6000（全部在用）\\\\n\\\\n## 关键决策日志\\\\n\\\\n| ID | 日期 | 摘要 | 关联实验 |\\\\n|----|------|------|----------|\\\\n| D114 | 2026-05-23 | Fix MATH-500 eval script bugs and rerun all method | eval_math500_sft_standard_20_2048_v3, eval_math500_grpo_standard_20_fair_2048_v3b |\\\\n| D113 | 2026-05-23 | Floor ablation table 改为 GRPO-only 格式；放弃 SFT eval 和 | floor_ablation_0p3_cka_only_20_v2, floor_ablation_0p5_cka_only_20_v2 |\\\\n| D112 | 2026-05-22 | D112: C1 max |Δ| 修正为 1.34pp（含 MBPP），D111 的 1.14pp  | — |\\\\n| D111 | 2026-05-22 | C1 quantified upgrade to \\\\\\\"universal accuracy-rewar | — |\\\\n| D110 | 2026-05-22 | depth-first baseline放appendix作为sanity check，不进主表；c | eval_gsm8k_sft_depth_first_20, eval_gsm8k_grpo_depth_first_20 |\\\\n| D109 | 2026-05-22 | Dose-response narrative 修正：纯 inverted-U，α=2.0 无争议  | eval_gsm8k_grpo_rasp_alpha3p0_20_v2 |\\\\n| D108 | 2026-05-22 | Dose-response narrative: α=2.0 optimal 为主 claim，GR | eval_gsm8k_sft_alpha3p0_20, eval_gsm8k_grpo_rasp_alpha3p0_20_v2 |\\\\n| D107 | 2026-05-22 | D107: α=1.0 数据点修正——55.19%/54.43% 无 registry 溯源，替换为 | eval_gsm8k_sft_rasp_20, eval_gsm8k_grpo_rasp_20_fair, eval_gsm8k_grpo_alpha2p0_20 |\\\\n| D106 | 2026-05-22 | D106: α dose-response 揭示非单调 U 型曲线，α=2.0 (66.11%) 超 | eval_gsm8k_grpo_alpha0p5_20, eval_gsm8k_grpo_alpha4_20_v3, eval_gsm8k_grpo_alpha2p0_20 |\\\\n| D105 | 2026-05-22 | D105: MF3 Qwen-Math GRPO 启动前修复 prompt 格式——chat tem | sft_qwen_math_cka_only_20, grpo_qwen_math_cka_only_20 |\\\\n\\\\n\\\\n\\\", \\\"lines\\\": 85}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/ROADMAP.md\", \"content\": \"# recovery_aware_struct_prune — Research Dashboard\\n\\n> 最后更新: 2026-05-23 20:05 UTC | 更新原因: Loop #21 全面刷新：MATH-500 fixed eval 唯一 blocking 项，已完成任务标记，stale GPU 状态修正\\n\\n## 核心方向\\nPruning criterion shapes recovery capacity — CKA-only >> Standard in reward (4.4×) and accuracy (4.55pp). Reward-accuracy decoupling: SFT ≈ GRPO accuracy despite vastly different rewards. 详见 paper_framing.md.\\n\\n## 当前阶段: 提交收尾 — DDL 5/25 (~27h)\\n\\n### 唯一 Blocking 项：MATH-500 Fixed Eval\\nD114 决定：旧 eval 脚本有 expression extraction + space normalization bug，全部 19 个 MATH-500 数据点需用 fixed script 重跑。\\n\\n**已完成 (2/19)**：\\n| Eval | Fixed Acc |\\n|------|-----------|\\n| sft_cka_only_20 | 27.4% (was 26.8%) |\\n| sft_rasp_alpha1p0_20 | 21.6% (was 21.2%) |\\n\\n**Running (6)**：Reviewer 19:52 UTC 确认全部健康，GPU 97-99%\\n- westd:0 — eval_math500_sft_standard_25_fixed (~6h)\\n- westd:1 — eval_math500_grpo_rasp_alpha1p0_20_fixed (~2h)\\n- westd:2 — eval_math500_grpo_standard_20_fixed (~2.5h)\\n- westd:3 — eval_math500_sft_standard_20_fixed (~2.5h)\\n- westb:0 — eval_math500_grpo_cka_only_20_fixed (~6h)\\n- westb:1 — eval_math500_sft_random_20_fixed (~6h)\\n\\n**待启动 (~11)**：dose-response α=0.5/2.0/3.0/4.0 × SFT/GRPO (8) + grpo_random_20 (需 checkpoint) + cka_only_25 SFT/GRPO (2)\\n- 25% Standard GRPO → '--'（checkpoint 丢失，不重训）\\n\\n### 已完成的论文修复\\n- [x] Floor ablation 附录表 (0.3=65.05, 0.4=64.37, 0.5=61.71, 0.6=62.02)\\n- [x] 数据完整性审计 ✅（4 处修复）\\n- [x] 匿名仓库 ✅（65 files, c9a2a2b）\\n- [x] Paper Banana → matplotlib 替代完成\\n- [x] C1 scope 全文一致性修复\\n- [x] 4 篇新引用验证\\n- [x] Conclusion 扩充\\n- [x] GRPO 超参审计 + 措辞修正\\n- [x] 论文编译正常（0 critical warnings, 15 pages）\\n\\n### 等 fixed eval 完成后\\n- [ ] 一次性更新 tab_math500.tex 全部数值\\n- [ ] 更新 experiments.tex:85 + appendix.tex:110 inline MATH-500 数值\\n- [ ] 修复 check_paper_consistency warning: 4.62pp 仅在 conclusion（可选）\\n- [ ] paper_compile_and_check + check_paper_consistency\\n- [ ] submit_paper_to_review 最终审查\\n- [ ] 最终提交\\n\\n### Review Issues 状态\\n- Round 1-3: 23/23 resolved ✅\\n- Round 5-6 remaining criticals (in_progress, rebuttal 准备):\\n  - R5-N1: GRPO narrative (dual-layer reframe)\\n  - R5-N2: Cross-arch GRPO (1.5B 数据已有)\\n  - R5-W2: CKA 因果机制 (correlational)\\n  - R6-N1: 单基准\\n  - R6-N2: depth confound\\n\\n## 服务器状态\\n- westd-32935：4× RTX PRO 6000 — 6 个 MATH-500 eval 在跑中\\n- westb-23072：2× RTX PRO 6000 — 2 个 MATH-500 eval 在跑中\\n\\n## 投稿目标\\n- EMNLP 2026 Main (ARR May 25) — **~27h**\\n\\n## GPU 预算\\n- westd-32935: 4× RTX PRO 6000（全部在用）\\n- westb-23072: 2× RTX PRO 6000（全部在用）\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 | 关联实验 |\\n|----|------|------|----------|\\n| D114 | 2026-05-23 | Fix MATH-500 eval script bugs and rerun all method | eval_math500_sft_standard_20_2048_v3, eval_math500_grpo_standard_20_fair_2048_v3b |\\n| D113 | 2026-05-23 | Floor ablation table 改为 GRPO-only 格式；放弃 SFT eval 和 | floor_ablation_0p3_cka_only_20_v2, floor_ablation_0p5_cka_only_20_v2 |\\n| D112 | 2026-05-22 | D112: C1 max |Δ| 修正为 1.34pp（含 MBPP），D111 的 1.14pp  | — |\\n| D111 | 2026-05-22 | C1 quantified upgrade to \\\"universal accuracy-rewar | — |\\n| D110 | 2026-05-22 | depth-first baseline放appendix作为sanity check，不进主表；c | eval_gsm8k_sft_depth_first_20, eval_gsm8k_grpo_depth_first_20 |\\n| D109 | 2026-05-22 | Dose-response narrative 修正：纯 inverted-U，α=2.0 无争议  | eval_gsm8k_grpo_rasp_alpha3p0_20_v2 |\\n| D108 | 2026-05-22 | Dose-response narrative: α=2.0 optimal 为主 claim，GR | eval_gsm8k_sft_alpha3p0_20, eval_gsm8k_grpo_rasp_alpha3p0_20_v2 |\\n| D107 | 2026-05-22 | D107: α=1.0 数据点修正——55.19%/54.43% 无 registry 溯源，替换为 | eval_gsm8k_sft_rasp_20, eval_gsm8k_grpo_rasp_20_fair, eval_gsm8k_grpo_alpha2p0_20 |\\n| D106 | 2026-05-22 | D106: α dose-response 揭示非单调 U 型曲线，α=2.0 (66.11%) 超 | eval_gsm8k_grpo_alpha0p5_20, eval_gsm8k_grpo_alpha4_20_v3, eval_gsm8k_grpo_alpha2p0_20 |\\n| D105 | 2026-05-22 | D105: MF3 Qwen-Math GRPO 启动前修复 prompt 格式——chat tem | sft_qwen_math_cka_only_20, grpo_qwen_math_cka_only_20 |\\n\\n\\n\", \"lines\": 85}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "6064fb4c-bb7c-40c4-9ecb-73ae01d095fe",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 22_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[CRON] 实验进程异常退出（失败），需要你诊断原因。 详情: Process exited without valid W&B metrics  - exp_id: eval_math500_sft_standard_20_fixed_v3 - project: recovery_aware_struct_prune - server: westd-32935 - log_path: ~/ru…",
  "leafUuid": "2c03b304-6ba4-495c-b992-3d30398f32b2",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699"
}
```

---

### Runtime record

_source line 23_

```json
{
  "type": "ai-title",
  "aiTitle": "Diagnose W&B metrics missing in failed experiment",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699"
}
```

---

### Assistant

_source line 24 · 2026-05-23T21:17:40.069Z_

<details><summary>Logged reasoning block</summary>

```text
Let me understand the situation:

1. The failed experiment is `eval_math500_sft_standard_20_fixed_v3` - but I see in the reconcile results, the cron for `eval_math500_sft_standard_20_fixed_v2` was also reconciled with EXIT_CODE=143 → DONE(failed). 

Wait, the CRON message says `eval_math500_sft_standard_20_fixed_v3` failed. Let me check the registry for this specific experiment and also check the ROADMAP which mentions `eval_math500_sft_standard_20_fixed` on westd:3.


Looking at the ROADMAP, `eval_math500_sft_standard_20_fixed` was running on westd:3 with an estimated 2.5 hour runtime, but the CRON indicates the v3 variant failed, and reconcile also shows v2 failed with EXIT_CODE=143. So I'm tracking multiple versions of this experiment across different failure points.

I need to pull the experiment details from the registry, check the on-experiment-failed skill, and spawn a worker to diagnose what's happening with the logs. I also noticed `eval_math500_sft_random_20_fixed_v2` hit the same EXIT_CODE=143 failure, so there might be a pattern here worth investigating.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2c03b304-6ba4-495c-b992-3d30398f32b2",
  "isSidechain": false,
  "requestId": "req_011CbLCKKYowxG3g6Vicgnd5",
  "type": "assistant",
  "uuid": "75122256-79e2-42eb-8027-5b6140d5785e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0145NdUCcUetujiHyTbK7Z2P",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8480,
      "cache_read_input_tokens": 38878,
      "output_tokens": 1134,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8480,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1134,
          "cache_read_input_tokens": 38878,
          "cache_creation_input_tokens": 8480,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8480
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Assistant

_source line 25 · 2026-05-23T21:17:41.525Z_

Reconcile 完成，发现两个新失败：`eval_math500_sft_standard_20_fixed_v3` 和 `eval_math500_sft_random_20_fixed_v2`。正在查询失败实验详情并派 Worker 诊断。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "75122256-79e2-42eb-8027-5b6140d5785e",
  "isSidechain": false,
  "requestId": "req_011CbLCKKYowxG3g6Vicgnd5",
  "type": "assistant",
  "uuid": "9935b5dd-9eba-4474-b52a-76095053ebcc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0145NdUCcUetujiHyTbK7Z2P",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8480,
      "cache_read_input_tokens": 38878,
      "output_tokens": 1134,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8480,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1134,
          "cache_read_input_tokens": 38878,
          "cache_creation_input_tokens": 8480,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8480
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-23T21:17:48.635Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01TmTmPbkk79nYqtbWaZRkjm`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune--claude-sessions-agent-853ea75a/dc0980c3-5832-4647-951a-4335ba333699/tool-results/mcp-agent-ml-research-read_registry-1779570987788.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nregistry = json.loads(data['result'])\nexps = registry.get('data', {}).get('experiments', [])\ntargets = ['eval_math500_sft_standard_20_fixed_v3', 'eval_math500_sft_standard_20_fixed_v2', 'eval_math500_sft_standard_20_fixed', 'eval_math500_sft_random_20_fixed_v2', 'eval_math500_sft_random_20_fixed']\nfor e in exps:\n    if e.get('exp_id') in targets:\n        print(json.dumps(e, indent=2, default=str))\n        print('---')\n\"\n",
  "description": "Extract failed experiment details from registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9935b5dd-9eba-4474-b52a-76095053ebcc",
  "isSidechain": false,
  "requestId": "req_011CbLCKKYowxG3g6Vicgnd5",
  "type": "assistant",
  "uuid": "4d1fd729-3aeb-40c4-aa4f-e848eea26a8c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0145NdUCcUetujiHyTbK7Z2P",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8480,
      "cache_read_input_tokens": 38878,
      "output_tokens": 1134,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8480,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1134,
          "cache_read_input_tokens": 38878,
          "cache_creation_input_tokens": 8480,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8480
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 27 · 2026-05-23T21:17:49.068Z_

<details><summary>↩ Tool result · reported error · `toolu_01TmTmPbkk79nYqtbWaZRkjm`</summary>

```text
Exit code 1
Traceback (most recent call last):
  File "&lt;string>", line 8, in &lt;module>
    if e.get('exp_id') in targets:
       ^^^^^
AttributeError: 'str' object has no attribute 'get'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4d1fd729-3aeb-40c4-aa4f-e848eea26a8c",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "6c99ea00-dfbc-4527-a104-6603377cb037",
  "toolUseResult": "Error: Exit code 1\nTraceback (most recent call last):\n  File \"&lt;string>\", line 8, in &lt;module>\n    if e.get('exp_id') in targets:\n       ^^^^^\nAttributeError: 'str' object has no attribute 'get'",
  "sourceToolAssistantUUID": "4d1fd729-3aeb-40c4-aa4f-e848eea26a8c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-23T21:17:50.059Z_

<details open><summary>🔧 Tool call — Read · `toolu_01L8dNdyXiTgEU1ZrztDeBRk`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/skills/on-experiment-failed.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6c99ea00-dfbc-4527-a104-6603377cb037",
  "isSidechain": false,
  "requestId": "req_011CbLCKKYowxG3g6Vicgnd5",
  "type": "assistant",
  "uuid": "53dafa66-f8f1-4578-98be-ff415a80effc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0145NdUCcUetujiHyTbK7Z2P",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8480,
      "cache_read_input_tokens": 38878,
      "output_tokens": 1134,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8480,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1134,
          "cache_read_input_tokens": 38878,
          "cache_creation_input_tokens": 8480,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8480
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 29 · 2026-05-23T21:17:50.061Z_

<details><summary>↩ Tool result · reported error · `toolu_01L8dNdyXiTgEU1ZrztDeBRk`</summary>

```text
&lt;tool_use_error>Cancelled: parallel tool call Bash(cat /home/ubuntu/.claude-account-1/proje…) errored&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "53dafa66-f8f1-4578-98be-ff415a80effc",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "cc3716a5-a974-4bd9-ba2e-2ca016387b1a",
  "toolUseResult": "Cancelled: parallel tool call Bash(cat /home/ubuntu/.claude-account-1/proje…) errored",
  "sourceToolAssistantUUID": "53dafa66-f8f1-4578-98be-ff415a80effc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 30 · 2026-05-23T21:17:59.509Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01J3P4Xx21eqcNSnMzxYXaBw`</summary>

```json
{
  "command": "python3 -c \"\nimport json\nwith open('/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune--claude-sessions-agent-853ea75a/dc0980c3-5832-4647-951a-4335ba333699/tool-results/mcp-agent-ml-research-read_registry-1779570987788.txt') as f:\n    data = json.load(f)\nresult = json.loads(data['result'])\nexps = result.get('data', {}).get('experiments', {})\nprint(type(exps), len(exps) if isinstance(exps, (list,dict)) else 'N/A')\nif isinstance(exps, dict):\n    for k in list(exps.keys())[:3]:\n        print(k, type(exps[k]))\nelif isinstance(exps, list):\n    for e in exps[:2]:\n        print(type(e), e[:100] if isinstance(e, str) else list(e.keys())[:5])\n\"\n",
  "description": "Probe registry data structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cc3716a5-a974-4bd9-ba2e-2ca016387b1a",
  "isSidechain": false,
  "requestId": "req_011CbLCMsNHwjPCSj9UeQ7jR",
  "type": "assistant",
  "uuid": "40f77a48-b1ca-4a38-b5aa-a269c738e76d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RT2Fpt2imDmDgAdvXnny56",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1294,
      "cache_read_input_tokens": 47358,
      "output_tokens": 345,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1294,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 345,
          "cache_read_input_tokens": 47358,
          "cache_creation_input_tokens": 1294,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1294
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 31 · 2026-05-23T21:17:59.640Z_

<details><summary>↩ Tool result · `toolu_01J3P4Xx21eqcNSnMzxYXaBw`</summary>

```text
&lt;class 'dict'> 454
eval_math500_sft_standard_20_fixed_v3 &lt;class 'dict'>
eval_math500_sft_standard_25_fixed_v2 &lt;class 'dict'>
eval_math500_sft_standard_25_fixed &lt;class 'dict'>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "40f77a48-b1ca-4a38-b5aa-a269c738e76d",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "218e8319-22c4-445e-912e-8d45149375be",
  "toolUseResult": {
    "stdout": "&lt;class 'dict'> 454\neval_math500_sft_standard_20_fixed_v3 &lt;class 'dict'>\neval_math500_sft_standard_25_fixed_v2 &lt;class 'dict'>\neval_math500_sft_standard_25_fixed &lt;class 'dict'>",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "40f77a48-b1ca-4a38-b5aa-a269c738e76d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 32 · 2026-05-23T21:17:59.648Z_

```json
{
  "parentUuid": "218e8319-22c4-445e-912e-8d45149375be",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "8766b739-5fb9-4636-940d-57d89aff424e",
  "timestamp": "2026-05-23T21:17:59.648Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Tool call

_source line 33 · 2026-05-23T21:18:04.425Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01A1zEZMCugP7Pz1ixPkUq8m`</summary>

```json
{
  "command": "python3 -c \"\nimport json\nwith open('/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune--claude-sessions-agent-853ea75a/dc0980c3-5832-4647-951a-4335ba333699/tool-results/mcp-agent-ml-research-read_registry-1779570987788.txt') as f:\n    data = json.load(f)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\ntargets = ['eval_math500_sft_standard_20_fixed_v3', 'eval_math500_sft_standard_20_fixed_v2', 'eval_math500_sft_standard_20_fixed', 'eval_math500_sft_random_20_fixed_v2', 'eval_math500_sft_random_20_fixed']\nfor t in targets:\n    if t in exps:\n        e = exps[t]\n        print(f'=== {t} ===')\n        print(json.dumps(e, indent=2, default=str))\n        print()\n\"\n",
  "description": "Extract target experiment details from registry dict"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8766b739-5fb9-4636-940d-57d89aff424e",
  "isSidechain": false,
  "requestId": "req_011CbLCNZrsCLe5Um4WyePTd",
  "type": "assistant",
  "uuid": "72000a09-802d-4c5c-9c8c-9065b034351f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015drLXkBbDsT8NayVy45SCV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 536,
      "cache_read_input_tokens": 48652,
      "output_tokens": 452,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 536,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 452,
          "cache_read_input_tokens": 48652,
          "cache_creation_input_tokens": 536,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 536
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 34 · 2026-05-23T21:18:04.505Z_

<details><summary>↩ Tool result · `toolu_01A1zEZMCugP7Pz1ixPkUq8m`</summary>

```text
=== eval_math500_sft_standard_20_fixed_v3 ===
{
  "status": "PREPARING",
  "created_at": "2026-05-23T21:05:21.000Z",
  "updated_at": "2026-05-23T21:15:51.935Z",
  "hypothesis": "SFT Standard 20% MATH-500 with fixed eval script. v1 crashed at 328/500, v2 killed by timeout (10h too short for ~17h eval). v3 with timeout=20h. P0 method comparison.",
  "conclusion": "failed"
}

=== eval_math500_sft_standard_20_fixed_v2 ===
{
  "status": "DONE",
  "created_at": "2026-05-23T20:10:23.626Z",
  "updated_at": "2026-05-23T21:09:23.483Z",
  "hypothesis": "SFT Standard 20% MATH-500 with fixed eval script. Retry of v1 which crashed at 328/500. P0 method comparison.",
  "conclusion": "killed"
}

=== eval_math500_sft_standard_20_fixed ===
{
  "status": "DONE",
  "created_at": "2026-05-23T14:42:20.750Z",
  "updated_at": "2026-05-23T20:10:08.647Z",
  "hypothesis": "SFT Standard 20% MATH-500 with fixed eval script. Replaces OLD v2 (25.8%) and buggy NEW v3 (23.4%) with consistent scoring.",
  "conclusion": "failed"
}

=== eval_math500_sft_random_20_fixed_v2 ===
{
  "status": "PREPARING",
  "created_at": "2026-05-23T21:05:25.628Z",
  "updated_at": "2026-05-23T21:05:25.628Z"
}

=== eval_math500_sft_random_20_fixed ===
{
  "status": "DONE",
  "created_at": "2026-05-23T15:50:03.335Z",
  "updated_at": "2026-05-23T21:05:07.374Z",
  "hypothesis": "SFT Random 20% MATH-500 with fixed eval script. Model on westb (sft_random_20). P0 method comparison.",
  "conclusion": "killed"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "72000a09-802d-4c5c-9c8c-9065b034351f",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "0ea246a2-9fd7-42a9-b9ea-08487828a176",
  "toolUseResult": {
    "stdout": "=== eval_math500_sft_standard_20_fixed_v3 ===\n{\n  \"status\": \"PREPARING\",\n  \"created_at\": \"2026-05-23T21:05:21.000Z\",\n  \"updated_at\": \"2026-05-23T21:15:51.935Z\",\n  \"hypothesis\": \"SFT Standard 20% MATH-500 with fixed eval script. v1 crashed at 328/500, v2 killed by timeout (10h too short for ~17h eval). v3 with timeout=20h. P0 method comparison.\",\n  \"conclusion\": \"failed\"\n}\n\n=== eval_math500_sft_standard_20_fixed_v2 ===\n{\n  \"status\": \"DONE\",\n  \"created_at\": \"2026-05-23T20:10:23.626Z\",\n  \"updated_at\": \"2026-05-23T21:09:23.483Z\",\n  \"hypothesis\": \"SFT Standard 20% MATH-500 with fixed eval script. Retry of v1 which crashed at 328/500. P0 method comparison.\",\n  \"conclusion\": \"killed\"\n}\n\n=== eval_math500_sft_standard_20_fixed ===\n{\n  \"status\": \"DONE\",\n  \"created_at\": \"2026-05-23T14:42:20.750Z\",\n  \"updated_at\": \"2026-05-23T20:10:08.647Z\",\n  \"hypothesis\": \"SFT Standard 20% MATH-500 with fixed eval script. Replaces OLD v2 (25.8%) and buggy NEW v3 (23.4%) with consistent scoring.\",\n  \"conclusion\": \"failed\"\n}\n\n=== eval_math500_sft_random_20_fixed_v2 ===\n{\n  \"status\": \"PREPARING\",\n  \"created_at\": \"2026-05-23T21:05:25.628Z\",\n  \"updated_at\": \"2026-05-23T21:05:25.628Z\"\n}\n\n=== eval_math500_sft_random_20_fixed ===\n{\n  \"status\": \"DONE\",\n  \"created_at\": \"2026-05-23T15:50:03.335Z\",\n  \"updated_at\": \"2026-05-23T21:05:07.374Z\",\n  \"hypothesis\": \"SFT Random 20% MATH-500 with fixed eval script. Model on westb (sft_random_20). P0 method comparison.\",\n  \"conclusion\": \"killed\"\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "72000a09-802d-4c5c-9c8c-9065b034351f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 35 · 2026-05-23T21:18:05.049Z_

<details open><summary>🔧 Tool call — Read · `toolu_017pVbJTthrXieZzhAUzXc8F`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/skills/on-experiment-failed.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0ea246a2-9fd7-42a9-b9ea-08487828a176",
  "isSidechain": false,
  "requestId": "req_011CbLCNZrsCLe5Um4WyePTd",
  "type": "assistant",
  "uuid": "e60f227d-81f4-4bc4-8223-16b47f11b8de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015drLXkBbDsT8NayVy45SCV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 536,
      "cache_read_input_tokens": 48652,
      "output_tokens": 452,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 536,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 452,
          "cache_read_input_tokens": 48652,
          "cache_creation_input_tokens": 536,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 536
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 36 · 2026-05-23T21:18:05.061Z_

<details><summary>↩ Tool result · reported error · `toolu_017pVbJTthrXieZzhAUzXc8F`</summary>

```text
File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e60f227d-81f4-4bc4-8223-16b47f11b8de",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "8143c810-aec7-4279-a282-203a6b132f6e",
  "toolUseResult": "Error: File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a.",
  "sourceToolAssistantUUID": "e60f227d-81f4-4bc4-8223-16b47f11b8de",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 37 · 2026-05-23T21:18:20.573Z_

<details><summary>Logged reasoning block</summary>

```text
The failed experiment `eval_math500_sft_standard_20_fixed_v3` is still in PREPARING status with conclusion=failed. That's odd - it has conclusion=failed but status=PREPARING. This suggests the cron detected the failure but status wasn't updated properly. Let me also note:

- v1 (eval_math500_sft_standard_20_fixed): failed - crashed at 328/500
- v2 (eval_math500_sft_standard_20_fixed_v2): killed - timeout


- v3 (eval_math500_sft_standard_20_fixed_v3): failed - "Process exited without valid W&B metrics"

Also, `eval_math500_sft_random_20_fixed_v2` was reconciled as failed with EXIT_CODE=143 (SIGTERM/killed). I need to update the registry status for v3 to DONE(failed), spawn a Worker to SSH into westd-32935 and check the log file to understand what went wrong with v3, and address the random variant that got killed as well.

These are blocking critical eval runs for the EMNLP deadline in about 27 hours. Let me pull the full registry details for v3 including the spec and server information, then kick off a diagnostic worker to investigate.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8143c810-aec7-4279-a282-203a6b132f6e",
  "isSidechain": false,
  "requestId": "req_011CbLCNy6MjCUQXZNEEzusq",
  "type": "assistant",
  "uuid": "0513dd91-82c9-4547-88e3-5f1a6a8c4a6c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017UWJTENWxnAkPcWYPuqfqR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1201,
      "cache_read_input_tokens": 49188,
      "output_tokens": 693,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1201,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 693,
          "cache_read_input_tokens": 49188,
          "cache_creation_input_tokens": 1201,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1201
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-23T21:18:23.998Z_

<details open><summary>🔧 Tool call — Bash · `toolu_017N48ytfjT1e9ZoxSm8MphP`</summary>

```json
{
  "command": "python3 -c \"\nimport json\nwith open('/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune--claude-sessions-agent-853ea75a/dc0980c3-5832-4647-951a-4335ba333699/tool-results/mcp-agent-ml-research-read_registry-1779570987788.txt') as f:\n    data = json.load(f)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\ntargets = ['eval_math500_sft_standard_20_fixed_v3', 'eval_math500_sft_random_20_fixed_v2']\nfor t in targets:\n    if t in exps:\n        e = exps[t]\n        print(f'=== {t} ===')\n        # Print ALL fields\n        for k,v in sorted(e.items()):\n            print(f'  {k}: {json.dumps(v, default=str)}')\n        print()\n\"\n",
  "description": "Get full details for both failed experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0513dd91-82c9-4547-88e3-5f1a6a8c4a6c",
  "isSidechain": false,
  "requestId": "req_011CbLCNy6MjCUQXZNEEzusq",
  "type": "assistant",
  "uuid": "a2b969e7-6c62-4741-ba8f-2708bfcc8908",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017UWJTENWxnAkPcWYPuqfqR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1201,
      "cache_read_input_tokens": 49188,
      "output_tokens": 693,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1201,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 693,
          "cache_read_input_tokens": 49188,
          "cache_creation_input_tokens": 1201,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1201
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 39 · 2026-05-23T21:18:24.080Z_

<details><summary>↩ Tool result · `toolu_017N48ytfjT1e9ZoxSm8MphP`</summary>

```text
=== eval_math500_sft_standard_20_fixed_v3 ===
  conclusion: "failed"
  created_at: "2026-05-23T21:05:21.000Z"
  hypothesis: "SFT Standard 20% MATH-500 with fixed eval script. v1 crashed at 328/500, v2 killed by timeout (10h too short for ~17h eval). v3 with timeout=20h. P0 method comparison."
  status: "PREPARING"
  updated_at: "2026-05-23T21:15:51.935Z"

=== eval_math500_sft_random_20_fixed_v2 ===
  created_at: "2026-05-23T21:05:25.628Z"
  status: "PREPARING"
  updated_at: "2026-05-23T21:05:25.628Z"
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a2b969e7-6c62-4741-ba8f-2708bfcc8908",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "e64ad983-5f19-4bc7-9f36-4a39fd242e87",
  "toolUseResult": {
    "stdout": "=== eval_math500_sft_standard_20_fixed_v3 ===\n  conclusion: \"failed\"\n  created_at: \"2026-05-23T21:05:21.000Z\"\n  hypothesis: \"SFT Standard 20% MATH-500 with fixed eval script. v1 crashed at 328/500, v2 killed by timeout (10h too short for ~17h eval). v3 with timeout=20h. P0 method comparison.\"\n  status: \"PREPARING\"\n  updated_at: \"2026-05-23T21:15:51.935Z\"\n\n=== eval_math500_sft_random_20_fixed_v2 ===\n  created_at: \"2026-05-23T21:05:25.628Z\"\n  status: \"PREPARING\"\n  updated_at: \"2026-05-23T21:05:25.628Z\"",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "a2b969e7-6c62-4741-ba8f-2708bfcc8908",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 40_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[CRON] 实验进程异常退出（失败），需要你诊断原因。 详情: Process exited without valid W&B metrics  - exp_id: eval_math500_sft_standard_20_fixed_v3 - project: recovery_aware_struct_prune - server: westd-32935 - log_path: ~/ru…",
  "leafUuid": "e64ad983-5f19-4bc7-9f36-4a39fd242e87",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699"
}
```

---

### Runtime record

_source line 41_

```json
{
  "type": "ai-title",
  "aiTitle": "Diagnose W&B metrics missing in failed experiment",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699"
}
```

---

### Assistant

_source line 42 · 2026-05-23T21:18:41.445Z_

<details><summary>Logged reasoning block</summary>

```text
Interesting - `eval_math500_sft_standard_20_fixed_v3` has status=PREPARING but conclusion=failed. It seems like the cron detected the process died but the status wasn't properly updated to DONE. And it doesn't have a spec field, meaning it was either not properly submitted through submit_training_job, or the spec wasn't set.

Also, `eval_math500_sft_random_20_fixed_v2` is still in PREPARING status with no conclusion. But the reconcile showed it got EXIT_CODE=143 → DONE(failed). Let me re-read the reconcile output more carefully:


The reconcile already updated this one to DONE(failed), but my earlier registry read happened before the reconcile finished since they ran in parallel. So the registry snapshot I saw was stale.

Now for `eval_math500_sft_standard_20_fixed_v3` — the CRON callback shows it failed with no valid W&B metrics, but the registry still has it as PREPARING. I need to update the registry to DONE(failed) and then spawn a worker to diagnose the logs on both servers. I should also check what's happening with `eval_math500_sft_standard_25_fixed_v2` since it appeared in the registry but reconcile showed it as running. Let me cross-reference against the ROADMAP to see which GPUs these jobs were supposed to be running on.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e64ad983-5f19-4bc7-9f36-4a39fd242e87",
  "isSidechain": false,
  "requestId": "req_011CbLCQNGALiM9eeVwxc3y2",
  "type": "assistant",
  "uuid": "73780a56-6bb5-4a74-a7ff-b7fa9faa3848",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HeG89SvuoxgJKPUxcfyQ8N",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 926,
      "cache_read_input_tokens": 50389,
      "output_tokens": 871,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 926,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 871,
          "cache_read_input_tokens": 50389,
          "cache_creation_input_tokens": 926,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 926
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Assistant

_source line 43 · 2026-05-23T21:18:42.313Z_

两个失败实验都是 MATH-500 fixed eval 的 P0 blocking 项。DDL 不到 27 小时。先更新 registry，然后派 Worker 诊断。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "73780a56-6bb5-4a74-a7ff-b7fa9faa3848",
  "isSidechain": false,
  "requestId": "req_011CbLCQNGALiM9eeVwxc3y2",
  "type": "assistant",
  "uuid": "fa77ebf2-3adb-430c-ae68-43bc74e3037f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HeG89SvuoxgJKPUxcfyQ8N",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 926,
      "cache_read_input_tokens": 50389,
      "output_tokens": 871,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 926,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 871,
          "cache_read_input_tokens": 50389,
          "cache_creation_input_tokens": 926,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 926
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 44 · 2026-05-23T21:18:43.642Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_018gD5AfpWb8kPCmmwn87MFP`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__update_registry,mcp__agent-ml-research__spawn_worker,mcp__agent-ml-research__get_worker_status",
  "max_results": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fa77ebf2-3adb-430c-ae68-43bc74e3037f",
  "isSidechain": false,
  "requestId": "req_011CbLCQNGALiM9eeVwxc3y2",
  "type": "assistant",
  "uuid": "77c052c7-280f-4f0c-98a9-643b4bf56af8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HeG89SvuoxgJKPUxcfyQ8N",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 926,
      "cache_read_input_tokens": 50389,
      "output_tokens": 871,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 926,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 871,
          "cache_read_input_tokens": 50389,
          "cache_creation_input_tokens": 926,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 926
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 45 · 2026-05-23T21:18:43.649Z_

<details><summary>↩ Tool result · `toolu_018gD5AfpWb8kPCmmwn87MFP`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__update_registry"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__spawn_worker"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__get_worker_status"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "77c052c7-280f-4f0c-98a9-643b4bf56af8",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "63523026-16b5-4179-9f3a-d0c85139edd9",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__update_registry",
      "mcp__agent-ml-research__spawn_worker",
      "mcp__agent-ml-research__get_worker_status"
    ],
    "query": "select:mcp__agent-ml-research__update_registry,mcp__agent-ml-research__spawn_worker,mcp__agent-ml-research__get_worker_status",
    "total_deferred_tools": 82
  },
  "sourceToolAssistantUUID": "77c052c7-280f-4f0c-98a9-643b4bf56af8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 46 · 2026-05-23T21:19:00.360Z_

<details><summary>Logged reasoning block</summary>

````text
Now let me update the registry for `eval_math500_sft_standard_20_fixed_v3` to DONE(failed), and spawn a Worker to diagnose both failures by reading the logs on the servers.

Let me also check what the `eval_math500_sft_random_20_fixed_v2` situation is - the reconcile already moved it to DONE(failed) with EXIT_CODE=143. But actually, looking at the reconcile output again:

```
eval_math500_sft_random_20_fixed_v2: Sentinel EXIT_CODE=143 → Registry → DONE(failed), Cron deleted


```

So that one was already updated by reconcile. Good.

For `eval_math500_sft_standard_20_fixed_v3`, the status is PREPARING but the conclusion is failed, and the CRON callback indicates it's running on westd-32935 with logs at ~/runs/recovery_aware_struct_prune/eval_math500_sft_standard_20_fixed_v3.log. I need to update the registry status to DONE, set the failure reason, and spawn a worker to read the logs and diagnose what went wrong. The fact that it's stuck in PREPARING suggests it never completed its initialization properly.

```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "63523026-16b5-4179-9f3a-d0c85139edd9",
  "isSidechain": false,
  "requestId": "req_011CbLCRpBAsH12UagHrYW67",
  "type": "assistant",
  "uuid": "e698d48a-2573-4650-8f89-d98949eca1ae",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NQV9ffSrmz97Wmg6ob3pfw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2770,
      "cache_read_input_tokens": 51315,
      "output_tokens": 1507,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1507,
          "cache_read_input_tokens": 51315,
          "cache_creation_input_tokens": 2770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2770
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 47 · 2026-05-23T21:19:00.766Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__update_registry · `toolu_01E7txKmRWGQABoENLxnmPK8`</summary>

```json
{
  "exp_id": "eval_math500_sft_standard_20_fixed_v3",
  "field": "status",
  "value": "DONE",
  "project": "recovery_aware_struct_prune"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e698d48a-2573-4650-8f89-d98949eca1ae",
  "isSidechain": false,
  "requestId": "req_011CbLCRpBAsH12UagHrYW67",
  "type": "assistant",
  "uuid": "f5093c71-0ae5-45e2-bc51-4aa542ccb3e2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NQV9ffSrmz97Wmg6ob3pfw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2770,
      "cache_read_input_tokens": 51315,
      "output_tokens": 1507,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1507,
          "cache_read_input_tokens": 51315,
          "cache_creation_input_tokens": 2770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2770
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 48 · 2026-05-23T21:19:02.160Z_

<details><summary>↩ Tool result · `toolu_01E7txKmRWGQABoENLxnmPK8`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"Invalid transition: PREPARING → DONE. Allowed: ['PENDING', 'QUEUED']\", \"metadata\": {\"elapsed_seconds\": 1.3759}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f5093c71-0ae5-45e2-bc51-4aa542ccb3e2",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "13577037-db96-41f2-b3be-3ec4ec9953b6",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"Invalid transition: PREPARING → DONE. Allowed: ['PENDING', 'QUEUED']\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 1.3759}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"Invalid transition: PREPARING → DONE. Allowed: ['PENDING', 'QUEUED']\", \"metadata\": {\"elapsed_seconds\": 1.3759}}"
    }
  },
  "sourceToolAssistantUUID": "f5093c71-0ae5-45e2-bc51-4aa542ccb3e2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 49 · 2026-05-23T21:19:17.559Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__spawn_worker · `toolu_01XGfmKwoHC72Pr2hSod7YBp`</summary>

```json
{
  "task_type": "diagnose:eval_math500_sft_standard_20_fixed_v3",
  "project": "recovery_aware_struct_prune",
  "task_prompt": "## 任务：诊断两个 MATH-500 eval 实验失败原因\n\nDDL: EMNLP 2026 ARR May 25，不到 27 小时。这些是 P0 blocking eval。\n\n### 实验 1: eval_math500_sft_standard_20_fixed_v3\n- 服务器: westd-32935\n- 日志: ~/runs/recovery_aware_struct_prune/eval_math500_sft_standard_20_fixed_v3.log\n- 背景: v1 crashed at 328/500, v2 killed by timeout (10h), v3 设了 timeout=20h 但仍然失败\n- CRON 报告: \"Process exited without valid W&B metrics\"\n- 之前在 westd-32935:cuda:3 上运行\n\n### 实验 2: eval_math500_sft_random_20_fixed_v2\n- 服务器: westb-23072 (可能) 或 westd-32935\n- 日志: ~/runs/recovery_aware_struct_prune/eval_math500_sft_random_20_fixed_v2.log\n- EXIT_CODE=143 (SIGTERM)\n- 之前 v1 (eval_math500_sft_random_20_fixed) 也被 killed\n\n### 你需要做的：\n1. SSH 到 westd-32935，读取 eval_math500_sft_standard_20_fixed_v3.log 的最后 200 行，分析失败原因\n2. 检查该进程是否还存在：`ps aux | grep eval_math500_sft_standard_20_fixed_v3`\n3. 同样在 westb-23072 上查 eval_math500_sft_random_20_fixed_v2.log\n4. 如果日志不在上述路径，试 ~/runs/recovery_aware_struct_prune/ 目录下 ls 查找\n5. 查看 eval 脚本本身：找到 fixed eval 脚本路径，看是否有明显 bug 导致反复崩溃\n\n### 关键问题：\n- 是 OOM？timeout？脚本 bug？模型加载失败？\n- v1 crash at 328/500 是什么错误？如果 v3 也在类似位置崩溃，说明是脚本问题而非资源问题\n- 为什么 SFT eval 总失败，而 GRPO eval 目前正常运行？\n\n### 输出要求：\n总结失败根因，给出修复方案（具体到代码改动或命令参数调整）。如果能快速修复（改一行代码），直接修复并告诉我怎么重新提交。",
  "tool_groups": [
    "ssh",
    "registry"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "13577037-db96-41f2-b3be-3ec4ec9953b6",
  "isSidechain": false,
  "requestId": "req_011CbLCRpBAsH12UagHrYW67",
  "type": "assistant",
  "uuid": "d5ac0a6a-6ee3-43b0-8c2b-170c9962f218",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NQV9ffSrmz97Wmg6ob3pfw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2770,
      "cache_read_input_tokens": 51315,
      "output_tokens": 1507,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2770,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1507,
          "cache_read_input_tokens": 51315,
          "cache_creation_input_tokens": 2770,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2770
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 50 · 2026-05-23T21:19:21.538Z_

<details><summary>↩ Tool result · `toolu_01XGfmKwoHC72Pr2hSod7YBp`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"worker_id\": \"worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918\", \"status\": \"running\", \"log_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/logs/workers/worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918.log\", \"setup_data\": {}, \"message\": \"Worker worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918 started. Use get_worker_status('worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918') to check progress.\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d5ac0a6a-6ee3-43b0-8c2b-170c9962f218",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "63f88f7f-5ba5-485a-a81d-311cba985bad",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"worker_id\\\": \\\"worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918\\\", \\\"status\\\": \\\"running\\\", \\\"log_path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/logs/workers/worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918.log\\\", \\\"setup_data\\\": {}, \\\"message\\\": \\\"Worker worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918 started. Use get_worker_status('worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918') to check progress.\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"worker_id\": \"worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918\", \"status\": \"running\", \"log_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/logs/workers/worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918.log\", \"setup_data\": {}, \"message\": \"Worker worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918 started. Use get_worker_status('worker_diagnose_eval_math500_sft_standard_20_fixed_v3_20260523T211918') to check progress.\"}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "d5ac0a6a-6ee3-43b0-8c2b-170c9962f218",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 51 · 2026-05-23T21:19:57.090Z_

<details><summary>Logged reasoning block</summary>

```text
The registry update failed because we can't transition from PREPARING to DONE directly. The experiment was in PREPARING state. Let me try a different approach - maybe I need to go through the proper state transitions, or update via a different mechanism.

Actually, looking at this more carefully, the cron set conclusion=failed on this experiment, but the status is still PREPARING. This is because the experiment was probably submitted outside of the proper pipeline (or was created but the status wasn't updated to RUNNING before it started). 

Let me try to set it through the intermediate states, or set the status directly to something else. Actually, the allowed transitions from PREPARING are PENDING or QUEUED. 

I could try stepping through QUEUED → ALLOCATED → RUNNING → DONE, but honestly this is a data integrity issue - the experiment was clearly running (the cron was monitoring it and detected it died), yet the registry never got updated past PREPARING. Rather than getting bogged down in fixing the registry state, I should focus on what actually matters: getting the diagnostic results and resubmitting the eval. The status inconsistency is secondary.

Let me also check what's happening with that other experiment the reconcile showed as running.

Looking at the reconcile results, I've got four experiments still actively running with valid PIDs, one that hit exit code 143 and got marked as failed with its cron deleted, and one that was already done so its stale cron got removed.

Now I need to figure out the resource situation more carefully—I see eval_math500_sft_standard_25_fixed_v2 is running according to reconcile, but it wasn't listed in the RUNNING section of the report, so I should check which GPU it's actually occupying and verify the full registry to understand the current allocation. Westd:3 and westb:1 just freed up after their v3 and v2 runs failed respectively, so I have two GPUs available now. The Worker is investigating what went wrong, and once I identify the root cause, I can resubmit the jobs to these freed slots. The real issue is that the experiment got stuck with a failed conclusion but never transitioned through the proper status states. Rather than trying to manually step through intermediate states, I should focus on what matters—getting the Worker diagnostics back, fixing the root cause, and resubmitting. The registry cleanup can wait. Now let me look at the resource-saturation skill requirements since I have idle GPUs.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "63f88f7f-5ba5-485a-a81d-311cba985bad",
  "isSidechain": false,
  "requestId": "req_011CbLCUbwYnJZwTkbLSB7fD",
  "type": "assistant",
  "uuid": "1153bffc-0d8d-4f9a-9c51-a76fe4fb5861",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015tyRzMTMDAubz8CgKYGEu6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1885,
      "cache_read_input_tokens": 54085,
      "output_tokens": 1669,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1885,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1669,
          "cache_read_input_tokens": 54085,
          "cache_creation_input_tokens": 1885,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1885
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Assistant

_source line 52 · 2026-05-23T21:19:57.095Z_

Registry 状态转换被阻止（PREPARING→DONE 不合法）。Worker 已派出诊断。同时读取 resource-saturation skill，因为有 2 个 GPU 空闲。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1153bffc-0d8d-4f9a-9c51-a76fe4fb5861",
  "isSidechain": false,
  "requestId": "req_011CbLCUbwYnJZwTkbLSB7fD",
  "type": "assistant",
  "uuid": "e921b25d-140b-4088-b603-6cdbab5d824d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015tyRzMTMDAubz8CgKYGEu6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1885,
      "cache_read_input_tokens": 54085,
      "output_tokens": 1669,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1885,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1669,
          "cache_read_input_tokens": 54085,
          "cache_creation_input_tokens": 1885,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1885
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 53 · 2026-05-23T21:19:57.566Z_

<details open><summary>🔧 Tool call — Read · `toolu_013KYDqdrnqaZn1rbaPnEBLE`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/skills/resource-saturation.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e921b25d-140b-4088-b603-6cdbab5d824d",
  "isSidechain": false,
  "requestId": "req_011CbLCUbwYnJZwTkbLSB7fD",
  "type": "assistant",
  "uuid": "d24d750b-dbe4-43c1-b155-9f9dda5aca5b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015tyRzMTMDAubz8CgKYGEu6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1885,
      "cache_read_input_tokens": 54085,
      "output_tokens": 1669,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1885,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1669,
          "cache_read_input_tokens": 54085,
          "cache_creation_input_tokens": 1885,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1885
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 54 · 2026-05-23T21:19:57.577Z_

<details><summary>↩ Tool result · reported error · `toolu_013KYDqdrnqaZn1rbaPnEBLE`</summary>

```text
File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d24d750b-dbe4-43c1-b155-9f9dda5aca5b",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "e739ba28-046b-45e9-a31a-9d7b26b19ac6",
  "toolUseResult": "Error: File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a.",
  "sourceToolAssistantUUID": "d24d750b-dbe4-43c1-b155-9f9dda5aca5b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 55_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[CRON] 实验进程异常退出（失败），需要你诊断原因。 详情: Process exited without valid W&B metrics  - exp_id: eval_math500_sft_standard_20_fixed_v3 - project: recovery_aware_struct_prune - server: westd-32935 - log_path: ~/ru…",
  "leafUuid": "e739ba28-046b-45e9-a31a-9d7b26b19ac6",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699"
}
```

---

### Runtime record

_source line 56_

```json
{
  "type": "ai-title",
  "aiTitle": "Diagnose W&B metrics missing in failed experiment",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699"
}
```

---

### Tool call

_source line 57 · 2026-05-23T21:20:00.573Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01GdVLqugkqWuChSH9L9QkuL`</summary>

```json
{
  "pattern": "**/resource-saturation*",
  "path": "/home/ubuntu"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e739ba28-046b-45e9-a31a-9d7b26b19ac6",
  "isSidechain": false,
  "requestId": "req_011CbLCXHX6z9by6psJeETBz",
  "type": "assistant",
  "uuid": "d26f94a7-3830-4ae4-a2c5-4b112cb6f84f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MMq716jyEWsBoZiuxSodnC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1740,
      "cache_read_input_tokens": 55970,
      "output_tokens": 78,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1740,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 78,
          "cache_read_input_tokens": 55970,
          "cache_creation_input_tokens": 1740,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1740
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 58 · 2026-05-23T21:20:00.865Z_

<details><summary>↩ Tool result · `toolu_01GdVLqugkqWuChSH9L9QkuL`</summary>

```text
/home/ubuntu/agent-ml-research/skills/global/resource-saturation.skill.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d26f94a7-3830-4ae4-a2c5-4b112cb6f84f",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "40597d93-6637-4b63-93f8-e876676fc6e1",
  "toolUseResult": {
    "filenames": [
      "/home/ubuntu/agent-ml-research/skills/global/resource-saturation.skill.md"
    ],
    "durationMs": 283,
    "numFiles": 1,
    "truncated": false
  },
  "sourceToolAssistantUUID": "d26f94a7-3830-4ae4-a2c5-4b112cb6f84f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 59 · 2026-05-23T21:20:00.869Z_

```json
{
  "parentUuid": "40597d93-6637-4b63-93f8-e876676fc6e1",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "e76b5f17-e5f9-4356-bd9a-4807da6fd2b9",
  "timestamp": "2026-05-23T21:20:00.869Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Tool call

_source line 60 · 2026-05-23T21:20:03.426Z_

<details open><summary>🔧 Tool call — Read · `toolu_01HNTQfx4qAhUH66VFExDav3`</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/resource-saturation.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e76b5f17-e5f9-4356-bd9a-4807da6fd2b9",
  "isSidechain": false,
  "requestId": "req_011CbLCXW88qxLqp5DEEd3ia",
  "type": "assistant",
  "uuid": "d5374c43-0447-4041-8746-9dfcbe10148a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0117AMpTBijZaDa66YTW2kU5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 215,
      "cache_read_input_tokens": 57710,
      "output_tokens": 75,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 215,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 75,
          "cache_read_input_tokens": 57710,
          "cache_creation_input_tokens": 215,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 215
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 61 · 2026-05-23T21:20:03.432Z_

<details><summary>↩ Tool result · `toolu_01HNTQfx4qAhUH66VFExDav3`</summary>

```text
1	---
2	name: resource-saturation
3	description: "当你准备向 Director 汇报前、收到 cron/worker 回调、审批通过准备开跑、怀疑 Worker 池不够饱和时,立即使用本 skill。四部分:A) GPU 分配率(分配了没跑=失职) B) GPU 效率 C) 非 GPU 任务并行(Worker 池<2=失职) D) 汇报必须带 [资源] 行。"
4	always: false
5	roles:
6	  - director
7	  - agent
8	---
9	
10	# 资源饱和度自检（硬约束）
11	
12	## A. GPU 分配率检查
13	
14	调 `get_project_resource_usage(project)` 看:
15	- 已分配给本项目的 GPU 总数和具体卡号
16	- 实际在跑任务的 GPU 数和具体卡号（交叉 registry RUNNING + nvidia-smi 进程）
17	- 分配了但没跑的 GPU 清单 ⚠️
18	
19	任何"分配了但没跑"的 GPU = 失职。必须立即:
20	- 派 Worker 铺 dry-run / 下一批实验代码准备
21	- 铺 ablation（从 experiment-matrix 空白格子里挑）
22	- 确实无实验可铺 → 向 Director 汇报"暂无可铺实验"+ 建议下一步方向(扩 ablation 维度 / 加 baseline / 加 benchmark)。**不要建议归还 GPU**——项目级 GPU 归还只在归档时由 `archive_project` 自动触发, 不是 Director 中途的动作
23	
24	**单实验不占多卡**: 分配 4 卡但实验只用 1 卡 → 另 3 卡必须并行跑其他实验,不能空占。
25	
26	## B. GPU 效率检查
27	
28	调 `get_gpu_health(server)`:
29	- 空闲 GPU（util < 10% 持续 > 5 min）→ 立即铺任务
30	- 低利用率（util < 50% 持续 > 15 min）→ spawn_worker 诊断（batch / IO / 同步）
31	- OOM 风险（显存 > 90% 持续 10 min）→ 主动降 batch / 调优
32	
33	## C. 非 GPU 任务并行
34	
35	GPU 在跑 ≠ 你空闲。以下 CPU / 网络任务**必须**派独立 Worker 并行:
36	- 下一批实验的数据集下载 / 预处理 / fingerprint
37	- 下一批实验的代码准备 / dry-run / 环境配置
38	- 论文文献调研 / related work 检索
39	- 已完成实验的 log 深度分析 / metric 聚合
40	- 论文章节起草
41	- 代码 review / refactor
42	
43	**硬约束**: 任一时刻 Worker 池 < 2 个 = 失职（除非真的全部下游阻塞在等 GPU,这时应当向 Director 申请扩 GPU）。
44	
45	## D. 汇报格式
46	
47	向 Director 汇报时开头必须带资源声明行:
48	
49	    [资源] GPU 分配 N / 实际在跑 M | Worker 池 K (其中 GPU 任务 A / CPU 任务 B)
50	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d5374c43-0447-4041-8746-9dfcbe10148a",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "46ee2aa6-dfc1-40fe-8ead-910a9e7f18ff",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/resource-saturation.skill.md",
      "content": "---\nname: resource-saturation\ndescription: \"当你准备向 Director 汇报前、收到 cron/worker 回调、审批通过准备开跑、怀疑 Worker 池不够饱和时,立即使用本 skill。四部分:A) GPU 分配率(分配了没跑=失职) B) GPU 效率 C) 非 GPU 任务并行(Worker 池<2=失职) D) 汇报必须带 [资源] 行。\"\nalways: false\nroles:\n  - director\n  - agent\n---\n\n# 资源饱和度自检（硬约束）\n\n## A. GPU 分配率检查\n\n调 `get_project_resource_usage(project)` 看:\n- 已分配给本项目的 GPU 总数和具体卡号\n- 实际在跑任务的 GPU 数和具体卡号（交叉 registry RUNNING + nvidia-smi 进程）\n- 分配了但没跑的 GPU 清单 ⚠️\n\n任何\"分配了但没跑\"的 GPU = 失职。必须立即:\n- 派 Worker 铺 dry-run / 下一批实验代码准备\n- 铺 ablation（从 experiment-matrix 空白格子里挑）\n- 确实无实验可铺 → 向 Director 汇报\"暂无可铺实验\"+ 建议下一步方向(扩 ablation 维度 / 加 baseline / 加 benchmark)。**不要建议归还 GPU**——项目级 GPU 归还只在归档时由 `archive_project` 自动触发, 不是 Director 中途的动作\n\n**单实验不占多卡**: 分配 4 卡但实验只用 1 卡 → 另 3 卡必须并行跑其他实验,不能空占。\n\n## B. GPU 效率检查\n\n调 `get_gpu_health(server)`:\n- 空闲 GPU（util < 10% 持续 > 5 min）→ 立即铺任务\n- 低利用率（util < 50% 持续 > 15 min）→ spawn_worker 诊断（batch / IO / 同步）\n- OOM 风险（显存 > 90% 持续 10 min）→ 主动降 batch / 调优\n\n## C. 非 GPU 任务并行\n\nGPU 在跑 ≠ 你空闲。以下 CPU / 网络任务**必须**派独立 Worker 并行:\n- 下一批实验的数据集下载 / 预处理 / fingerprint\n- 下一批实验的代码准备 / dry-run / 环境配置\n- 论文文献调研 / related work 检索\n- 已完成实验的 log 深度分析 / metric 聚合\n- 论文章节起草\n- 代码 review / refactor\n\n**硬约束**: 任一时刻 Worker 池 < 2 个 = 失职（除非真的全部下游阻塞在等 GPU,这时应当向 Director 申请扩 GPU）。\n\n## D. 汇报格式\n\n向 Director 汇报时开头必须带资源声明行:\n\n    [资源] GPU 分配 N / 实际在跑 M | Worker 池 K (其中 GPU 任务 A / CPU 任务 B)\n",
      "numLines": 50,
      "startLine": 1,
      "totalLines": 50
    }
  },
  "sourceToolAssistantUUID": "d5374c43-0447-4041-8746-9dfcbe10148a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 62 · 2026-05-23T21:20:31.168Z_

<details><summary>Logged reasoning block</summary>

```text
Now I understand the resource situation clearly:
- 6 GPUs allocated, 4 running → 2 idle (westd:3, westb:1) = 失职
- Worker pool = 1 (diagnostic worker) < 2 = 失职

I need to:
1. Wait for diagnostic Worker to return
2. Once I know the root cause, immediately resubmit the fixed evals on the free GPUs

But actually, I shouldn't just wait. I should also check what other experiments need to run. The ROADMAP says there are ~11 待启动 experiments for dose-response evaluations.


The two failed experiments map perfectly to my two idle GPUs, so once the diagnostic worker identifies the issue, I can immediately resubmit them. However, I should flag this idle GPU situation to the Director since it violates the resource-saturation principle.

While waiting for the diagnostic callback, I'm also considering whether to fix the registry state for v3 or just create a fresh v4 entry instead—but that's secondary to understanding why the SFT evals are failing while GRPO runs smoothly. Let me hold steady on the current assessment and see what the worker uncovers.

Actually, I realize I need to report to the Director now with the resource status line, then follow the proper protocol: once the worker diagnoses, I'll update the registry, notify the Director with findings, and prepare the fix. The rules say to report immediately after spawning the worker rather than polling for its status.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "46ee2aa6-dfc1-40fe-8ead-910a9e7f18ff",
  "isSidechain": false,
  "requestId": "req_011CbLCXhCtXdrMyXGXZHHsr",
  "type": "assistant",
  "uuid": "fbdf80a6-e518-451d-9868-3129b44299ed",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B9ZTmrWZyQUtcm5XDvYKKw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1147,
      "cache_read_input_tokens": 57925,
      "output_tokens": 961,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1147,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 961,
          "cache_read_input_tokens": 57925,
          "cache_creation_input_tokens": 1147,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1147
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Assistant

_source line 63 · 2026-05-23T21:20:32.098Z_

现状：4 个 eval 仍在运行，2 个刚失败（westd:3 和 westb:1 空闲）。诊断 Worker 已派出。向 Director 汇报当前情况。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fbdf80a6-e518-451d-9868-3129b44299ed",
  "isSidechain": false,
  "requestId": "req_011CbLCXhCtXdrMyXGXZHHsr",
  "type": "assistant",
  "uuid": "2773c875-6b5c-4e61-8ac0-6c989e887a0b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B9ZTmrWZyQUtcm5XDvYKKw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1147,
      "cache_read_input_tokens": 57925,
      "output_tokens": 961,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1147,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 961,
          "cache_read_input_tokens": 57925,
          "cache_creation_input_tokens": 1147,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1147
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 64 · 2026-05-23T21:20:33.495Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01Wiwtu5zqM76hSpYkDcCSMb`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__main_agent_post_to_director",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2773c875-6b5c-4e61-8ac0-6c989e887a0b",
  "isSidechain": false,
  "requestId": "req_011CbLCXhCtXdrMyXGXZHHsr",
  "type": "assistant",
  "uuid": "4e4d21f0-81ba-4a83-901e-df986262f2ea",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B9ZTmrWZyQUtcm5XDvYKKw",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1147,
      "cache_read_input_tokens": 57925,
      "output_tokens": 961,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1147,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 961,
          "cache_read_input_tokens": 57925,
          "cache_creation_input_tokens": 1147,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1147
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 65 · 2026-05-23T21:20:33.500Z_

<details><summary>↩ Tool result · `toolu_01Wiwtu5zqM76hSpYkDcCSMb`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__main_agent_post_to_director"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4e4d21f0-81ba-4a83-901e-df986262f2ea",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "0b5c7787-c77b-499d-876b-fa83247743d5",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__main_agent_post_to_director"
    ],
    "query": "select:mcp__agent-ml-research__main_agent_post_to_director",
    "total_deferred_tools": 82
  },
  "sourceToolAssistantUUID": "4e4d21f0-81ba-4a83-901e-df986262f2ea",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 66 · 2026-05-23T21:20:46.980Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__main_agent_post_to_director · `toolu_01N451YSLqSEByiVndgbLypL`</summary>

```json
{
  "text": "[资源] GPU 4/6 在跑 | Worker 1 (诊断中) | 空闲 GPU: westd:3, westb:1\n磁盘: westd-32935 48%used (435G可用), westb-23072 48%used (395G可用)\n\n**[实验失败] 2个 MATH-500 SFT eval 刚失败，诊断中**\n\n1. **eval_math500_sft_standard_20_fixed_v3** (westd:3) — \"Process exited without valid W&B metrics\"\n   - 历史：v1 crash at 328/500, v2 killed by timeout, v3 设 timeout=20h 仍失败\n   - SFT standard 20% 是 P0 数据点\n\n2. **eval_math500_sft_random_20_fixed_v2** (westb:1) — EXIT_CODE=143 (SIGTERM)\n   - v1 也被 killed\n\n**仍在运行 (4个)**：\n- westd:0 — sft_standard_25_fixed_v2 (pid=166236)\n- westd:1 — grpo_rasp_alpha1p0_20_fixed (pid=145167)\n- westd:2 — grpo_standard_20_fixed (pid=142477)\n- westb:0 — grpo_cka_only_20_fixed (pid=321423)\n\n**观察**：GRPO eval 全部正常运行，SFT eval 反复失败。已派 Worker SSH 读日志诊断根因。诊断完成后立即修复并在 westd:3 和 westb:1 上重新提交。",
  "project": "recovery_aware_struct_prune"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0b5c7787-c77b-499d-876b-fa83247743d5",
  "isSidechain": false,
  "requestId": "req_011CbLCZuaLJumaQWuox639a",
  "type": "assistant",
  "uuid": "90989aaf-f7d5-4959-81cb-d58b212f123c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018eHHyg7HAhWV2kDMkzbMpF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1245,
      "cache_read_input_tokens": 59072,
      "output_tokens": 535,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1245,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 535,
          "cache_read_input_tokens": 59072,
          "cache_creation_input_tokens": 1245,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1245
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 67 · 2026-05-23T21:20:48.097Z_

<details><summary>↩ Tool result · `toolu_01N451YSLqSEByiVndgbLypL`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"director_session\": \"feishu:group:oc_04e6cf8fe41be27a49d5657e80962f12:director\"}, \"error\": \"\"}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "90989aaf-f7d5-4959-81cb-d58b212f123c",
  "isSidechain": false,
  "promptId": "10a3468b-266b-454d-a6f4-85940cde1f4f",
  "type": "user",
  "uuid": "3465307b-5f20-4f46-b0a9-21bb2211b854",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"director_session\\\": \\\"feishu:group:oc_04e6cf8fe41be27a49d5657e80962f12:director\\\"}, \\\"error\\\": \\\"\\\"}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"director_session\": \"feishu:group:oc_04e6cf8fe41be27a49d5657e80962f12:director\"}, \"error\": \"\"}"
    }
  },
  "sourceToolAssistantUUID": "90989aaf-f7d5-4959-81cb-d58b212f123c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/.claude/sessions/agent_853ea75a",
  "sessionId": "dc0980c3-5832-4647-951a-4335ba333699",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---
