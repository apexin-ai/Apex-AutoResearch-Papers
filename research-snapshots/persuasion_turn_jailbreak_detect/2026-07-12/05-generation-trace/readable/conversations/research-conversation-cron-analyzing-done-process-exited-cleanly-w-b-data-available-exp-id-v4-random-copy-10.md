# Research conversation: [CRON] 实验进程已正常退出，状态已转为 ANALYZING，需要你分析结果并推进到 DONE。 详情: Process exited cleanly, W&B data available - exp_id: v4-random-fi

**DisPeD: A Controlled Study of Encoder Adaptation for Multi-Turn Jailbreak Detection (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 46
- **Recorded user turns:** 1
- **Tool calls:** 11
- **Original source:** `logs/chats/exported-trajectories/account-2/317bd1cf-f718-48d3-9b82-4f5aa233ca0e.jsonl`
- **Structured JSON:** [`83f38bbd7202d6d78236.json`](../../sessions/83/83f38bbd7202d6d78236.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-15T22:13:04.343Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-15T22:13:04.343Z",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "content": "[CRON] 实验进程已正常退出，状态已转为 ANALYZING，需要你分析结果并推进到 DONE。\n详情: Process exited cleanly, W&B data available\n\n- exp_id: v4-random-fixed-inject10-s7-eval\n- project: tax_error_inject_agent\n- server: autodl-5090\n- log_path: ~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s7-eval.log"
}
```

---

### Runtime record

_source line 2 · 2026-05-15T22:13:04.348Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-15T22:13:04.348Z",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e"
}
```

---

## Round 1

44 recorded events

### User

_source line 3 · 2026-05-15T22:13:04.401Z_

[CRON] 实验进程已正常退出，状态已转为 ANALYZING，需要你分析结果并推进到 DONE。
详情: Process exited cleanly, W&B data available

- exp_id: v4-random-fixed-inject10-s7-eval
- project: tax_error_inject_agent
- server: autodl-5090
- log_path: ~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s7-eval.log

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "ab45a8ae-902e-4214-8ca0-f7e851e514d1",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-15T22:13:04.400Z_

```json
{
  "parentUuid": "ab45a8ae-902e-4214-8ca0-f7e851e514d1",
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
      "mcp__agent-ml-research__edit_paper_section",
      "mcp__agent-ml-research__feishu_read_tum_pending_key",
      "mcp__agent-ml-research__feishu_send_alert",
      "mcp__agent-ml-research__feishu_send_approval_card",
      "mcp__agent-ml-research__feishu_send_result_card",
      "mcp__agent-ml-research__feishu_send_tum_key_request_card",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__get_baseline_metrics",
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
      "mcp__agent-ml-research__edit_paper_section",
      "mcp__agent-ml-research__feishu_read_tum_pending_key",
      "mcp__agent-ml-research__feishu_send_alert",
      "mcp__agent-ml-research__feishu_send_approval_card",
      "mcp__agent-ml-research__feishu_send_result_card",
      "mcp__agent-ml-research__feishu_send_tum_key_request_card",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__get_baseline_metrics",
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
  "uuid": "60da76f5-5321-454e-9d94-98dffd84505e",
  "timestamp": "2026-05-15T22:13:04.400Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-15T22:13:04.400Z_

```json
{
  "parentUuid": "60da76f5-5321-454e-9d94-98dffd84505e",
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
  "uuid": "10b490e9-c3b9-43bc-b174-b0f7e114413f",
  "timestamp": "2026-05-15T22:13:04.400Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-15T22:13:04.400Z_

```json
{
  "parentUuid": "10b490e9-c3b9-43bc-b174-b0f7e114413f",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "8326cfe8-f548-4fcf-bfba-bb1cf328f2ba",
  "timestamp": "2026-05-15T22:13:04.400Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
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
  "aiTitle": "Analyze experiment results and complete workflow",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e"
}
```

---

### Assistant

_source line 8 · 2026-05-15T22:13:10.753Z_

<details><summary>Logged reasoning block</summary>

```text
收到 CRON 回调，实验 `v4-random-fixed-inject10-s7-eval` 已完成，需要分析结果。按 session-start 规范，先初始化项目状态。

让我先执行 session-start 初始化，然后处理这个实验完成回调。
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8326cfe8-f548-4fcf-bfba-bb1cf328f2ba",
  "isSidechain": false,
  "requestId": "req_011Cb586rBufG9kWYfZodsqC",
  "type": "assistant",
  "uuid": "2b44a969-f4c6-44a9-99c7-a49a0fcc3b64",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016P3zh1EC3TqaRtUNmqh7F8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 22995,
      "cache_read_input_tokens": 11841,
      "output_tokens": 258,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 22995,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 258,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 22995,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 22995
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

_source line 9 · 2026-05-15T22:13:11.271Z_

Session 启动，先初始化项目状态，然后处理实验完成回调。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2b44a969-f4c6-44a9-99c7-a49a0fcc3b64",
  "isSidechain": false,
  "requestId": "req_011Cb586rBufG9kWYfZodsqC",
  "type": "assistant",
  "uuid": "a087d63a-ba07-433b-9c7f-73b40723947c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016P3zh1EC3TqaRtUNmqh7F8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 22995,
      "cache_read_input_tokens": 11841,
      "output_tokens": 258,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 22995,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 258,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 22995,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 22995
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

_source line 10 · 2026-05-15T22:13:12.875Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01JLN8UJGL4qRhLKZTZKJ7Ce`</summary>

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
  "parentUuid": "a087d63a-ba07-433b-9c7f-73b40723947c",
  "isSidechain": false,
  "requestId": "req_011Cb586rBufG9kWYfZodsqC",
  "type": "assistant",
  "uuid": "4e5efcd0-ceb2-489c-8eac-5c2a14021da2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016P3zh1EC3TqaRtUNmqh7F8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 22995,
      "cache_read_input_tokens": 11841,
      "output_tokens": 258,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 22995,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 258,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 22995,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 22995
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

_source line 11 · 2026-05-15T22:13:12.883Z_

<details><summary>↩ Tool result · `toolu_01JLN8UJGL4qRhLKZTZKJ7Ce`</summary>

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
  "parentUuid": "4e5efcd0-ceb2-489c-8eac-5c2a14021da2",
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "4a0c2ae6-359e-485f-9e56-a1ecc258b898",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__reconcile_crons",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_roadmap"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__reconcile_crons,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_roadmap",
    "total_deferred_tools": 79
  },
  "sourceToolAssistantUUID": "4e5efcd0-ceb2-489c-8eac-5c2a14021da2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-15T22:13:16.395Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01BnBEGtnXmNWfz5ab5Vgimi`</summary>

```json
{
  "project": "tax_error_inject_agent",
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
  "parentUuid": "4a0c2ae6-359e-485f-9e56-a1ecc258b898",
  "isSidechain": false,
  "requestId": "req_011Cb587UbB2TDpiU77v9SxC",
  "type": "assistant",
  "uuid": "d80cb16a-2266-46e1-a4ea-1b61c5da5a06",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Yeq9e7ndLiLQghfRuotxD",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1136,
      "cache_read_input_tokens": 34836,
      "output_tokens": 242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1136,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 242,
          "cache_read_input_tokens": 34836,
          "cache_creation_input_tokens": 1136,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1136
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

_source line 13 · 2026-05-15T22:13:16.873Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__reconcile_crons · `toolu_01N2Wn4su8dFcGJhxmYpGtTS`</summary>

```json
{}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d80cb16a-2266-46e1-a4ea-1b61c5da5a06",
  "isSidechain": false,
  "requestId": "req_011Cb587UbB2TDpiU77v9SxC",
  "type": "assistant",
  "uuid": "4c73c802-3620-40c0-89d3-8493efbfc044",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Yeq9e7ndLiLQghfRuotxD",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1136,
      "cache_read_input_tokens": 34836,
      "output_tokens": 242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1136,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 242,
          "cache_read_input_tokens": 34836,
          "cache_creation_input_tokens": 1136,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1136
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

_source line 14 · 2026-05-15T22:13:17.026Z_

<details><summary>↩ Tool result · `toolu_01BnBEGtnXmNWfz5ab5Vgimi`</summary>

```text
Error: result (167,997 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent--claude-sessions-agent-3327eadd/317bd1cf-f718-48d3-9b82-4f5aa233ca0e/tool-results/mcp-agent-ml-research-read_registry-1778883197010.txt.
Format: JSON with schema: {result: string}
Use offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.
REQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:
- You MUST read the content from the file at /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent--claude-sessions-agent-3327eadd/317bd1cf-f718-48d3-9b82-4f5aa233ca0e/tool-results/mcp-agent-ml-research-read_registry-1778883197010.txt in sequential chunks until 100% of the content has been read.
- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.
- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d80cb16a-2266-46e1-a4ea-1b61c5da5a06",
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "80a0179a-2b35-4e41-8db4-ee22550e3dd1",
  "toolUseResult": "Error: result (167,997 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent--claude-sessions-agent-3327eadd/317bd1cf-f718-48d3-9b82-4f5aa233ca0e/tool-results/mcp-agent-ml-research-read_registry-1778883197010.txt.\nFormat: JSON with schema: {result: string}\nUse offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.\nREQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:\n- You MUST read the content from the file at /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-tax-error-inject-agent--claude-sessions-agent-3327eadd/317bd1cf-f718-48d3-9b82-4f5aa233ca0e/tool-results/mcp-agent-ml-research-read_registry-1778883197010.txt in sequential chunks until 100% of the content has been read.\n- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.\n- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***\n",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"v4-random-fixed-inject10-s7-eval\": {\"status\": \"ANALYZING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:57:41.705Z\", \"updated_at\": \"2026-05-15T22:12:58.041Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s7/v1-20260516-045440/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"202328\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s7-eval.log\", \"submitted_at\": \"2026-05-15T21:57:41.444Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s7)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s7\", \"eval_data\": \"eval_tasks_47.json\"}, \"hypothesis\": \"v4 Random 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion. 最后一个 10% eval。\", \"reproduce\": {\"finished_at\": \"2026-05-15T22:12:57.609Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:12:59.982752+00:00\"}]}}, \"v4-random-fixed-inject10-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:08.353Z\", \"updated_at\": \"2026-05-15T21:57:11.016Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion — 最后一个 10% 训练。\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s7)\", \"seed\": 7}, \"reproduce\": {\"finished_at\": \"2026-05-15T21:54:51.217Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:54:53.698171+00:00\"}]}, \"metrics\": {\"final_loss\": 0.2352, \"train_loss_avg\": 0.4209, \"final_token_acc\": 0.9066, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3511.93, \"memory_gib\": 18.15, \"train_speed_s_per_it\": 2.148}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s7/v1-20260516-045440/checkpoint-1635\", \"conclusion\": \"success\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s7.log\", \"completed_at\": \"2026-05-15T21:57:11.016Z\"}, \"v4-taxei-fixed-inject25-s7\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:32:12.446Z\", \"updated_at\": \"2026-05-15T21:32:49.561Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4_fixed_inject25.jsonl --lora_rank 16 --epochs 3 --seed 7\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"200226\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s7.log\", \"submitted_at\": \"2026-05-15T21:32:12.194Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 7}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio seed=7 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion.\"}, \"v4-random-fixed-inject25-s1\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:32:10.005Z\", \"updated_at\": \"2026-05-15T21:32:48.216Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_random_v4_fixed_inject25.jsonl --lora_rank 16 --epochs 3 --seed 1\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"200146\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-s1.log\", \"submitted_at\": \"2026-05-15T21:32:09.741Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1}, \"hypothesis\": \"v4 Random fixed-size ablation: 25% injection ratio seed=1 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion.\"}, \"v4-taxei-fixed-inject25-s1\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:29:07.506Z\", \"updated_at\": \"2026-05-15T21:29:44.762Z\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl --lora_rank 16 --num_train_epochs 3 --seed 1 --data_seed 1 --output_dir checkpoints/v4_taxei_fixed_inject25_s1 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"199599\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s1.log\", \"submitted_at\": \"2026-05-15T21:29:07.235Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio seed=1 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion.\"}, \"v4-random-fixed-inject10-s1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:05:18.654Z\", \"updated_at\": \"2026-05-15T21:27:48.360Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"198045\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s1-eval.log\", \"submitted_at\": \"2026-05-15T21:05:18.393Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s1)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635\", \"wall_clock_seconds\": 1350.0, \"gpu_hours\": 0.37}, \"hypothesis\": \"v4 Random 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T21:25:33.786Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:25:36.468478+00:00\"}]}, \"metrics\": {\"success_rate\": 0.681, \"successes\": 32, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 10, \"success\": 5, \"rate\": 0.5}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 6, \"rate\": 0.857}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:27:48.360Z\"}, \"v4-taxei-fixed-inject10-s7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:02:22.234Z\", \"updated_at\": \"2026-05-15T21:27:44.185Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject10_s7/v1-20260516-040128/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"197555\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s7-eval.log\", \"submitted_at\": \"2026-05-15T21:02:21.785Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s7)\", \"seed\": 42, \"checkpoint_source\": \"v4-taxei-fixed-inject10-s7\", \"eval_data\": \"eval_tasks_47.json\", \"wall_clock_seconds\": 1522.4, \"gpu_hours\": 0.42}, \"hypothesis\": \"v4 TaxEI 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T21:19:30.996Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:19:33.518373+00:00\"}]}, \"metrics\": {\"success_rate\": 0.681, \"successes\": 32, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_fixed_inject10_s7_eval.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:27:44.185Z\"}, \"v4-taxei-fixed-inject10-s1-eval-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:54:05.248Z\", \"updated_at\": \"2026-05-15T21:06:11.418Z\", \"spec\": {\"parent\": \"v4-taxei-fixed-inject10-s1\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s1)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\"}, \"hypothesis\": \"v4 TaxEI 10% seed=1 eval (r2, dedicated GPU) — 47 ALFWorld clean tasks.\", \"reproduce\": {\"finished_at\": \"2026-05-15T21:04:33.190Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:04:36.432028+00:00\"}]}, \"metrics\": {\"success_rate\": 0.511, \"successes\": 24, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 4, \"rate\": 0.667}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_fixed_inject10_s1_eval.json\", \"log_path\": \"/root/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1-eval-r2.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:06:11.418Z\"}, \"v4-taxei-fixed-inject10-s7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:05.524Z\", \"updated_at\": \"2026-05-15T21:05:01.494Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion.\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4_fixed_inject10.jsonl --seed 7\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"191997\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s7.log\", \"submitted_at\": \"2026-05-15T20:01:19.314Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"wall_clock_seconds\": 3683.3, \"gpu_hours\": 1.02}, \"reproduce\": {\"finished_at\": \"2026-05-15T20:59:13.748Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T20:59:16.071667+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s7/v1-20260516-040128/checkpoint-1635\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.237, \"train_loss_avg\": 0.4212, \"final_token_acc\": 0.905, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3437, \"memory_gib\": 18.15, \"train_speed_s_per_it\": 2.102}, \"completed_at\": \"2026-05-15T21:02:42.621Z\"}, \"v4-random-fixed-inject10-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:07.390Z\", \"updated_at\": \"2026-05-15T21:04:23.738Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion.\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_random_v4_fixed_inject10.jsonl --seed 1\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"192077\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s1.log\", \"submitted_at\": \"2026-05-15T20:01:21.468Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"wall_clock_seconds\": 3782.3, \"gpu_hours\": 1.05}, \"reproduce\": {\"finished_at\": \"2026-05-15T21:01:51.221Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:01:53.909162+00:00\"}]}, \"metrics\": {\"final_loss\": 0.3096, \"train_loss_avg\": 0.4238, \"final_token_acc\": 0.8902, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3488, \"memory_gib\": 18.13, \"train_speed_s_per_it\": 2.132}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:04:23.738Z\"}, \"v4-taxei-fixed-inject10-s123-eval-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:40:05.773Z\", \"updated_at\": \"2026-05-15T20:54:14.378Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"194978\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123-eval-r3.log\", \"submitted_at\": \"2026-05-15T20:40:05.519Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s123\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s123\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s123)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\", \"wall_clock_seconds\": 848.9, \"gpu_hours\": 0.24}, \"hypothesis\": \"v4 TaxEI 10% seed=123 eval (r3, dedicated GPU) — 47 ALFWorld clean tasks.\", \"reproduce\": {\"finished_at\": \"2026-05-15T20:50:16.884Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T20:50:19.215245+00:00\"}]}, \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\", \"completed_at\": \"2026-05-15T20:54:14.378Z\"}, \"v4-random-fixed-inject10-s0-eval-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:40:07.402Z\", \"updated_at\": \"2026-05-15T20:52:32.204Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"195118\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0-eval-r3.log\", \"submitted_at\": \"2026-05-15T20:40:07.156Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10-s0\", \"checkpoint_source\": \"v4-random-fixed-inject10-s0\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s0)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\", \"wall_clock_seconds\": 745.0, \"gpu_hours\": 0.21}, \"hypothesis\": \"v4 Random 10% seed=0 eval (r3, dedicated GPU) — 47 ALFWorld clean tasks.\", \"reproduce\": {\"finished_at\": \"2026-05-15T20:50:22.439Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T20:50:26.585713+00:00\"}]}, \"metrics\": {\"success_rate\": 0.66, \"successes\": 31, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"success\": 7, \"total\": 11, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 7, \"total\": 8, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\", \"completed_at\": \"2026-05-15T20:52:32.204Z\"}, \"v4-random-fixed-inject10-s0-eval-r2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:05:35.682Z\", \"updated_at\": \"2026-05-15T20:05:48.855Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_fixed_inject10_s0_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"193145\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0-eval-r2.log\", \"submitted_at\": \"2026-05-15T20:05:35.429Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10-s0\", \"checkpoint_source\": \"v4-random-fixed-inject10-s0\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s0)\", \"seed\": 42}, \"hypothesis\": \"v4 Random 10% seed=0 eval (retry, OOM fix) — 47 ALFWorld clean tasks. Dedicated GPU.\"}, \"v4-taxei-fixed-inject10-s123-eval-r2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:05:34.132Z\", \"updated_at\": \"2026-05-15T20:05:47.199Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_fixed_inject10_s123_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"193003\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123-eval-r2.log\", \"submitted_at\": \"2026-05-15T20:05:33.887Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s123\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s123\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s123)\", \"seed\": 42}, \"hypothesis\": \"v4 TaxEI 10% seed=123 eval (retry, OOM fix) — 47 ALFWorld clean tasks. Dedicated GPU.\"}, \"v4-random-fixed-inject10-s0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:43.603Z\", \"updated_at\": \"2026-05-15T20:04:12.753Z\", \"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"188022\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0-eval.log\", \"submitted_at\": \"2026-05-15T18:57:43.056Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10-s0\", \"checkpoint_source\": \"v4-random-fixed-inject10-s0\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"N/A\", \"model_name\": \"v4_random_fixed_inject10_s0\", \"seed\": 0, \"wall_clock_seconds\": 3975.6, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 Random 10% seed=0 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"checkpoint_path\": \"N/A-OOM\", \"completed_at\": \"2026-05-15T20:03:58.662Z\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-taxei-fixed-inject10-s123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:41.337Z\", \"updated_at\": \"2026-05-15T20:04:11.865Z\", \"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"187785\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123-eval.log\", \"submitted_at\": \"2026-05-15T18:57:40.646Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s123\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s123\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"N/A\", \"model_name\": \"v4_taxei_fixed_inject10_s123\", \"seed\": 123, \"wall_clock_seconds\": 3977.2, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 TaxEI 10% seed=123 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"checkpoint_path\": \"N/A-OOM\", \"completed_at\": \"2026-05-15T20:03:57.889Z\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-taxei-fixed-inject10-s1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:45.002Z\", \"updated_at\": \"2026-05-15T20:04:10.985Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_fixed_inject10_s1_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"188906\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1-eval.log\", \"submitted_at\": \"2026-05-15T18:57:44.756Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s1\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"data_path\": \"eval/eval_tasks_47.json\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"wall_clock_seconds\": 3927.9, \"gpu_hours\": 1.09}, \"hypothesis\": \"v4 TaxEI 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T20:03:12.659Z\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-random-fixed-inject10-s123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:59:20.398Z\", \"updated_at\": \"2026-05-15T20:04:09.526Z\", \"hypothesis\": \"v4 Random fixed-size 10% injection seed=123 eval — 47 ALFWorld tasks, dose-response 5-seed expansion\", \"parent\": \"v4-random-fixed-inject10-s123\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s123/v0-20260516-015429/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_fixed_inject10_s123_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s123\", \"eval_data\": \"eval/eval_tasks_47.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123-eval.log\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject10_s123_eval.json\", \"completed_at\": \"2026-05-15T20:03:32.060Z\", \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}}, \"v4-taxei-fixed-inject10-s0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:57:46.985Z\", \"updated_at\": \"2026-05-15T20:04:06.775Z\", \"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"188410\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s0-eval.log\", \"submitted_at\": \"2026-05-15T18:57:46.725Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s0\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s0\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"eval_results/v4_taxei_fixed_inject10_s0_eval.json\", \"model_name\": \"v4_taxei_fixed_inject10_s0\", \"seed\": 0, \"wall_clock_seconds\": 3970.2, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 TaxEI 10% seed=0 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_taxei_fixed_inject10_s0_eval.json\", \"completed_at\": \"2026-05-15T20:03:56.888Z\", \"metrics\": {\"success_rate\": 0.702, \"successes\": 33, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 8, \"rate\": 0.727}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}}, \"v4-taxei-fixed-inject10-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:54:17.800Z\", \"updated_at\": \"2026-05-15T18:57:47.705Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 1 --data_seed 1 --output_dir checkpoints/v4_taxei_fixed_inject10_s1 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"182703\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1.log\", \"submitted_at\": \"2026-05-15T17:54:17.595Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635\", \"wall_clock_seconds\": 3728.4, \"gpu_hours\": 1.04}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T18:53:12.812Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:53:14.974953+00:00\"}]}, \"metrics\": {\"final_loss\": 0.3013, \"train_loss_avg\": 0.4225, \"final_token_acc\": 0.8947, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3469, \"memory_gib\": 18.13, \"train_speed_s_per_it\": 2.121}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T18:56:25.993Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1.log\"}, \"v4-random-fixed-inject10-s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:54:20.390Z\", \"updated_at\": \"2026-05-15T18:57:42.428Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --data_seed 123 --output_dir checkpoints/v4_random_fixed_inject10_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"182781\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123.log\", \"submitted_at\": \"2026-05-15T17:54:20.028Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 3802.4, \"gpu_hours\": 1.06}, \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=123 (4,358 total). Dose-response 5-seed expansion.\", \"reproduce\": {\"finished_at\": \"2026-05-15T18:54:38.478Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:54:40.603963+00:00\"}]}, \"metrics\": {\"final_loss\": 0.3124, \"train_loss_avg\": 0.4236, \"final_token_acc\": 0.8867, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3535.7, \"train_samples_per_second\": 3.698, \"train_steps_per_second\": 0.462, \"memory_gib\": 18.95}, \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10_s123/v0-20260516-015429/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T18:57:42.428Z\"}, \"v4-taxei-fixed-inject10-s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:48:24.290Z\", \"updated_at\": \"2026-05-15T18:56:29.231Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --data_seed 123 --output_dir checkpoints/v4_taxei_fixed_inject10_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"180877\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123.log\", \"submitted_at\": \"2026-05-15T17:48:23.907Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\", \"wall_clock_seconds\": 4085.3, \"gpu_hours\": 1.13}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=123 (4,358 total = 3,922 clean + 436 injected). Dose-response 5-seed expansion — 补齐 10% 数据点。\", \"reproduce\": {\"finished_at\": \"2026-05-15T18:47:28.139Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:47:30.511963+00:00\"}]}, \"metrics\": {\"train_loss\": 0.4234, \"final_loss\": 0.3097, \"final_token_acc\": 0.8882, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3497, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T18:56:29.231Z\"}, \"v4-random-fixed-inject10-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:48:26.373Z\", \"updated_at\": \"2026-05-15T18:56:27.890Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --data_seed 0 --output_dir checkpoints/v4_random_fixed_inject10_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"180956\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0.log\", \"submitted_at\": \"2026-05-15T17:48:26.104Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\", \"wall_clock_seconds\": 4081.8, \"gpu_hours\": 1.13}, \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=0 (4,358 total). Dose-response 5-seed expansion — 与 TaxEI 10% 对比 taxonomy 标签效果。\", \"reproduce\": {\"finished_at\": \"2026-05-15T18:47:48.342Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:47:53.242073+00:00\"}]}, \"metrics\": {\"train_loss\": 0.4227, \"final_loss\": 0.276, \"final_token_acc\": 0.9067, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3531, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T18:56:27.890Z\"}, \"v4-training-dynamics-forward-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:56:31.230Z\", \"updated_at\": \"2026-05-15T17:55:40.616Z\", \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=2 bash scripts/run_training_dynamics_v2.sh\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"180322\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-training-dynamics-forward-v2.log\", \"submitted_at\": \"2026-05-15T16:56:31.040Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"training_dynamics\", \"data_count\": 0, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\", \"wall_clock_seconds\": 3546.9, \"gpu_hours\": 0.99}, \"conclusion\": \"success\", \"metrics\": {\"subsets_computed\": [\"vanilla_full\", \"taxei_full\", \"random_full\", \"taxei_inject10\", \"taxei_inject25\", \"taxei_inject50\"], \"taxei_inject50_injected_mean_loss\": 0.8185, \"taxei_inject50_clean_mean_loss\": 0.8514, \"per_operator\": {\"C1_ContextTruncation\": {\"mean\": 0.6489, \"n\": 101}, \"C4_ObservationMasking\": {\"mean\": 0.6782, \"n\": 92}, \"P1_StepOrderSwap\": {\"mean\": 0.6374, \"n\": 89}, \"P2_SubGoalDeletion\": {\"mean\": 0.6542, \"n\": 88}}, \"plots\": [\"subset_comparison\", \"operator_breakdown\", \"dose_response\"], \"output_dir\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\"}, \"completed_at\": \"2026-05-15T17:55:37.917Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-training-dynamics-forward-v2.log\"}, \"v4-taxei-fixed-inject10-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:52:30.170Z\", \"updated_at\": \"2026-05-15T17:55:38.973Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=0 (4,358 total = 3,922 clean + 436 injected). Dose-response 5-seed expansion — 10% 是最薄弱环节，仅有 seed=42 一个数据点。\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"injection_ratio\": 0.1, \"clean_count\": 3922, \"injected_count\": 436, \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --data_seed 0 --output_dir checkpoints/v4_taxei_fixed_inject10_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\", \"log_path\": \"checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/logging.jsonl\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4238, \"final_loss\": 0.3102, \"final_token_acc\": 0.8822, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3494, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\"}, \"completed_at\": \"2026-05-15T17:55:36.626Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s0.log\"}, \"v4-taxei-inject10-seed0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:46:10.420Z\", \"updated_at\": \"2026-05-15T17:53:36.371Z\", \"spec\": {\"hypothesis\": \"Dose-response 5-seed expansion: TaxEI 10% injection, seed=0 (fixed 4,358 total). 补齐 10% 只有 seed=42 一个数据点的短板。\", \"failure_reason\": \"duplicate of v4-taxei-fixed-inject10-s0, never submitted\"}, \"conclusion\": \"killed\"}, \"v4-random-inject10-seed0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:46:13.097Z\", \"updated_at\": \"2026-05-15T17:53:35.645Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset /root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --output_dir checkpoints/random_inject10_seed0/v0-$(date +%Y%m%d-%H%M%S) --num_train_epochs 3 --lora_rank 16 --lora_alpha 32 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --seed 0 --logging_steps 5 --save_strategy epoch --bf16 true --gradient_checkpointing true\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"181792\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-inject10-seed0.log\", \"submitted_at\": \"2026-05-15T17:48:59.472Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"duplicate of v4-random-fixed-inject10-s0, process no longer exists\"}, \"conclusion\": \"killed\"}, \"v4-taxei-inject10-seed123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:46:11.744Z\", \"updated_at\": \"2026-05-15T17:53:34.706Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset /root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --output_dir checkpoints/taxei_inject10_seed123/v0-$(date +%Y%m%d-%H%M%S) --num_train_epochs 3 --lora_rank 16 --lora_alpha 32 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --seed 123 --logging_steps 5 --save_strategy epoch --bf16 true --gradient_checkpointing true\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"181699\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-inject10-seed123.log\", \"submitted_at\": \"2026-05-15T17:48:56.845Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"duplicate of v4-taxei-fixed-inject10-s123, process no longer exists\"}, \"conclusion\": \"killed\"}, \"v4-random-seed7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:29:15.592Z\", \"updated_at\": \"2026-05-15T17:43:36.723Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_seed7_eval.json\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"179098\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed7-eval.log\", \"submitted_at\": \"2026-05-15T17:29:24.122Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random SFT seed=7)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-seed7\", \"eval_data\": \"eval_tasks_47.json\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387\", \"wall_clock_seconds\": 852.6, \"gpu_hours\": 0.24}, \"hypothesis\": \"v4 Random SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion ← 基于 v4-random-seed7\", \"reproduce\": {\"finished_at\": \"2026-05-15T17:40:45.965Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:40:48.585893+00:00\"}]}, \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T17:43:36.723Z\"}, \"v4-random-seed1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:17:51.435Z\", \"updated_at\": \"2026-05-15T17:32:36.551Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && mkdir -p eval_results && CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_seed1_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"178005\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed1-eval.log\", \"submitted_at\": \"2026-05-15T17:18:03.664Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 872.9, \"gpu_hours\": 0.24}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:30:35.329Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:30:38.085288+00:00\"}]}, \"metrics\": {\"success_rate\": 0.468, \"successes\": 22, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 2, \"total\": 8, \"rate\": 0.25}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 2, \"total\": 7, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}}}, \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed1-eval.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T17:32:36.551Z\"}, \"v4-random-seed7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:34:10.206Z\", \"updated_at\": \"2026-05-15T17:29:09.688Z\", \"hypothesis\": \"v4 Random SFT seed=7 (5-seed expansion) — 9,029 samples, LoRA rank=16, 3 epochs\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_random_v4.jsonl --lora_rank 16 --lora_alpha 32 --num_train_epochs 3 --seed 7 --output_dir checkpoints/mini_random_sft_v4_seed7 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"gpu\": \"cuda:1\", \"pid\": 164126, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed7.log\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:26:13.042Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:26:15.009112+00:00\"}]}, \"metrics\": {\"final_loss\": 0.173, \"final_token_acc\": 0.935, \"initial_loss\": 4.017, \"total_steps\": 3387, \"epochs\": 3, \"total_flos\": 697192362530058200, \"train_runtime_sec\": 6672, \"memory_gib\": 18.49}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed7.log\", \"completed_at\": \"2026-05-15T17:29:09.688Z\"}, \"v4-random-seed1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:21:02.077Z\", \"updated_at\": \"2026-05-15T17:17:33.614Z\", \"spec\": {\"hypothesis\": \"v4 Random SFT seed=1 (5-seed expansion) — 9,029 samples, LoRA rank=16, 3 epochs\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 train/sft_train.py --config configs/mini_random_sft_v4_seed1.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_random_v4\", \"data_count\": 1129, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"gpu\": [\"cuda:0\"], \"pid\": \"163009\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed1.log\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/\", \"submitted_at\": \"2026-05-15T15:23:31Z\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 6842.6, \"gpu_hours\": 1.9}, \"conclusion\": \"success\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387\", \"metrics\": {\"final_loss\": 0.167, \"final_token_acc\": 0.938, \"initial_loss\": 4.017, \"total_steps\": 3387, \"epochs\": 3, \"total_flos\": 697000000000000000}, \"completed_at\": \"2026-05-15T17:17:33.614Z\"}, \"v4-taxei-seed1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:39:59.021Z\", \"updated_at\": \"2026-05-15T16:53:41.245Z\", \"hypothesis\": \"v4 TaxEI SFT seed=1 eval — 47 ALFWorld tasks, 5-seed expansion\", \"parent\": \"v4-taxei-seed1\", \"spec\": {\"command\": \"python eval_agent.py --checkpoint checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387 --split valid_unseen\", \"server\": \"autodl-5090\", \"data_path\": \"valid_unseen\", \"data_count\": 47, \"model_name\": \"mini_taxei_sft_v4_seed1/checkpoint-3387\", \"seed\": 1, \"checkpoint_source\": \"v4-taxei-seed1\", \"eval_data\": \"valid_unseen\", \"gpu\": [\"cuda:2\"], \"pid\": 173824, \"log_path\": \"eval_results/v4_taxei_seed1_eval.json\", \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\", \"parent\": \"v4-taxei-seed1\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T16:53:35.955Z\", \"metrics\": {\"success_rate\": 0.596, \"successes\": 28, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}}, \"v4-vanilla-seed1-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:49:28.411Z\", \"updated_at\": \"2026-05-15T16:43:19.834Z\", \"hypothesis\": \"v4 Vanilla SFT seed=1 eval — 47 ALFWorld tasks, 5-seed expansion\", \"parent\": \"v4-vanilla-seed1\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_vanilla_seed1_eval.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=1)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"gpu\": [\"cuda:0\"]}, \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-seed1-eval.log\", \"checkpoint_path\": \"eval_results/v4_vanilla_seed1_eval.json\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.66, \"eval_successes\": 31, \"eval_total\": 47, \"vs_seed42_pp\": 4.3}, \"completed_at\": \"2026-05-15T16:42:21.398Z\"}, \"v4-taxei-seed7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:40:01.513Z\", \"updated_at\": \"2026-05-15T16:40:14.867Z\", \"hypothesis\": \"v4 TaxEI SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion\", \"parent\": \"v4-taxei-seed7\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_seed7_eval.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (TaxEI v4 seed=7)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-taxei-seed7\", \"gpu\": [\"cuda:3\"], \"pid\": \"165338\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed7-eval.log\", \"checkpoint_path\": \"eval_results/v4_taxei_seed7_eval.json\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.617, \"successes\": 29, \"total\": 47, \"by_task\": {\"look_at_obj_in_light\": \"4/6 (0.667)\", \"pick_and_place_simple\": \"5/8 (0.625)\", \"pick_clean_then_place_in_recep\": \"5/11 (0.455)\", \"pick_cool_then_place_in_recep\": \"4/7 (0.571)\", \"pick_heat_then_place_in_recep\": \"7/8 (0.875)\", \"pick_two_obj_and_place\": \"4/7 (0.571)\"}}, \"completed_at\": \"2026-05-15T16:40:14.867Z\"}, \"v4-training-dynamics-forward\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:48:36.487Z\", \"updated_at\": \"2026-05-15T16:37:23.642Z\", \"hypothesis\": \"D027 Training Dynamics: Post-hoc forward pass on seed=42 checkpoints (Vanilla/TaxEI/Random + dose-response 10%/25%/50%) — compute per-subset loss (clean vs injected) and per-operator loss (P1/P2/C1/C4). Key finding: training loss SD=0.0004 across seeds but eval SD=8.6pp — memorization-generalization dissociation.\", \"spec\": {\"command\": \"bash scripts/run_training_dynamics.sh\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/\", \"data_count\": 6, \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"metrics\": {\"vanilla_full\": {\"clean_loss\": 0.6853, \"clean_n\": 4358}, \"taxei_full\": {\"clean_loss\": 0.7712, \"injected_loss\": 0.6139, \"clean_n\": 8269, \"injected_n\": 760, \"per_operator\": {\"P1_StepOrderSwap\": 0.6165, \"P2_SubGoalDeletion\": 0.6161, \"C1_ContextTruncation\": 0.5932, \"C4_ObservationMasking\": 0.6298}}, \"random_full\": {\"clean_loss\": 0.7354, \"injected_loss\": 0.5902, \"clean_n\": 8269, \"injected_n\": 760}, \"dose_response\": {\"taxei_10pct\": {\"clean_loss\": 0.6628, \"injected_loss\": 0.6464, \"gap\": -0.0164, \"injected_n\": 70}, \"taxei_25pct\": {\"clean_loss\": 0.701, \"injected_loss\": 0.574, \"gap\": -0.127, \"injected_n\": 168}, \"taxei_50pct\": {\"clean_loss\": 0.8516, \"injected_loss\": 0.6547, \"gap\": -0.1969, \"injected_n\": 370}}, \"key_findings\": \"Clear dose-response: injected-clean gap widens from -0.016 (10%) to -0.127 (25%) to -0.197 (50%). TaxEI operators C1_ContextTruncation consistently lowest loss. Higher injection rates also degrade clean sample loss (0.663→0.701→0.852).\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics/\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics/\", \"completed_at\": \"2026-05-15T16:35:47.805Z\"}, \"qualitative-failure-analysis\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:43:33.358Z\", \"updated_at\": \"2026-05-15T15:43:47.361Z\", \"hypothesis\": \"D026 Qualitative Failure Analysis: Extract failure patterns from existing eval logs. Key finding: TaxEI loop_repetition rate 17.4% vs Vanilla 7.8% vs Random 3.2%. TaxEI models exhibit fixation behavior (repeated action loops) especially on multi-step tasks under P1/P2 operators.\", \"conclusion\": \"success\", \"metrics\": {\"data_source\": \"eval_results/failure_analysis.json\", \"taxei_loop_repetition_rate\": 0.174, \"vanilla_loop_repetition_rate\": 0.078, \"random_loop_repetition_rate\": 0.032, \"taxei_loop_count\": 49, \"vanilla_loop_count\": 22, \"random_loop_count\": 6, \"per_operator\": {\"P1\": 15, \"P2\": 14, \"C1\": 11, \"C4\": 9}, \"note\": \"Random data only from seed=42 recovery eval + 3-seed clean eval (188 episodes vs 282). Rates to be updated after 5-seed completion.\"}}, \"v4-taxei-seed1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:40:26.898Z\", \"updated_at\": \"2026-05-15T15:39:39.545Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 1 --lora_rank 16 --lora_alpha 32 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"gpu\": \"cuda:2\", \"pid\": 154937}, \"metrics\": {\"final_loss\": 0.1667, \"avg_loss\": 0.3561, \"token_accuracy\": 0.915, \"final_token_acc\": 0.942, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 108.9, \"memory_gib\": 18.49, \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T15:30:06.293Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:30:07.753494+00:00\"}]}, \"conclusion\": \"success\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed1.log\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\", \"completed_at\": \"2026-05-15T15:39:39.545Z\"}, \"v4-taxei-seed7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:40:29.737Z\", \"updated_at\": \"2026-05-15T15:39:16.334Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 7 --lora_rank 16 --lora_alpha 32 --3epochs\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"gpu\": \"cuda:3\", \"pid\": 155145}, \"metrics\": {\"current_step\": 3387, \"total_steps\": 3387, \"progress_pct\": 100, \"train_loss\": 0.3568, \"final_step_loss\": 0.1753, \"token_acc\": 0.9009, \"final_token_acc\": 0.9328, \"train_runtime_s\": 6591.9, \"epochs\": 3, \"peak_memory_gib\": 18.49, \"gpu\": \"cuda:3\", \"pid\": 155145}, \"reproduce\": {\"finished_at\": \"2026-05-15T15:32:43.183Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:32:44.276153+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed7.log\", \"completed_at\": \"2026-05-15T15:36:45.958Z\"}, \"v4-vanilla-seed7-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:49:11.983Z\", \"updated_at\": \"2026-05-15T15:32:42.490Z\", \"hypothesis\": \"v4 Vanilla SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion\", \"parent\": \"v4-vanilla-seed7\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --num_episodes 47 --output eval_results/v4_vanilla_seed7_eval.json --device cuda:1 --seed 42\", \"server\": \"autodl-5090\", \"data_path\": \"eval/47 ALFWorld valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=7)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-vanilla-seed7\", \"gpu\": [\"cuda:1\"], \"pid\": \"160587\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-seed7-eval.log\", \"checkpoint_path\": \"eval_results/v4_vanilla_seed7_eval.json\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.745, \"eval_successes\": 35, \"eval_total\": 47, \"vs_seed42_pp\": 12.8}, \"completed_at\": \"2026-05-15T15:32:42.490Z\"}, \"v4-vanilla-seed1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:40:21.621Z\", \"updated_at\": \"2026-05-15T14:49:23.447Z\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_vanilla_v4.jsonl --seed 1 --lora_rank 16 --lora_alpha 32 --3epochs\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_vanilla_v4.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"gpu\": \"cuda:0\", \"pid\": 154589, \"checkpoint_path\": \"checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635\", \"log_path\": \"checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/\"}, \"metrics\": {\"final_loss\": 0.292, \"avg_loss\": 0.416, \"token_accuracy\": 0.903, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58.8, \"memory_gib\": 17.63, \"checkpoint_path\": \"checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T14:39:36.578Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T14:39:37.963564+00:00\"}]}, \"conclusion\": \"success\", \"hypothesis\": \"D010 Phase 1: v4 Vanilla SFT seed=1 多种子验证 — 4,358 samples, LoRA rank=16, 3 epochs, 与 seed=42 的 61.7% 对比波动范围\", \"completed_at\": \"2026-05-15T14:49:23.447Z\"}, \"v4-vanilla-seed7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:45:24.536Z\", \"updated_at\": \"2026-05-15T14:46:55.133Z\", \"hypothesis\": \"D010 Phase 1: v4 Vanilla SFT seed=7 多种子验证 — 4,358 samples, LoRA rank=16, 3 epochs, 与 seed=42 的 61.7% 对比波动范围\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_vanilla_v4.jsonl --seed 7 --lora_rank 16 --lora_alpha 32 --3epochs\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_vanilla_v4.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"gpu\": \"cuda:1\", \"pid\": 154666}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T18:20:48.185Z\", \"metrics\": {\"final_loss\": 0.295, \"avg_loss\": 0.415, \"token_accuracy\": 0.898, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 59.4, \"checkpoint_path\": \"checkpoints/mini_vanilla_sft_v4_seed7/v0-20260515-214031/checkpoint-1635\"}}, \"v4-recovery-paired-datagen\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:07:23.715Z\", \"updated_at\": \"2026-05-15T14:07:30.498Z\", \"hypothesis\": \"Recovery-paired injection data generation: 711 injected variants × GPT API recovery demos. Each injected trajectory gets a paired recovery continuation from the error state. For recovery-paired SFT training.\", \"metrics\": {\"total_variants\": 711, \"operators\": {\"P1\": 170, \"P2\": 184, \"C1\": 182, \"C4\": 175}, \"api_calls_est\": 5408, \"cost_est_usd\": 15.31, \"pid\": 158010, \"output_file\": \"data/recovery_paired/recovery_paired.jsonl\", \"log_file\": \"logs/recovery_paired_gen.log\", \"eta_hours\": 10}}, \"v4-random-recovery-eval-s123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:44:11.530Z\", \"updated_at\": \"2026-05-15T12:44:11.531Z\", \"spec\": {\"model_name\": \"Qwen3-8B\", \"seed\": 123, \"method\": \"random\", \"eval_type\": \"recovery\", \"parent\": \"v4-random-sft-seed123\", \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"eval_data\": \"47 ALFWorld injected eval (round-robin)\", \"server\": \"autodl-5090\"}}, \"v4-random-recovery-eval-s0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:44:10.000Z\", \"updated_at\": \"2026-05-15T12:44:10.000Z\", \"spec\": {\"model_name\": \"Qwen3-8B\", \"seed\": 0, \"method\": \"random\", \"eval_type\": \"recovery\", \"parent\": \"v4-random-sft-seed0\", \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed0/v0-20260515-014329/checkpoint-3387\", \"eval_data\": \"47 ALFWorld injected eval (round-robin)\", \"server\": \"autodl-5090\"}}, \"v4-taxei-recovery-eval-s123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:43:43.113Z\", \"updated_at\": \"2026-05-15T12:43:58.466Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/injected_eval.py --model_path checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant taxei --output eval_results/v4_taxei_recovery_eval_s123.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"148159\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-recovery-eval-s123.log\", \"submitted_at\": \"2026-05-15T12:43:58.296Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"v4-taxei-recovery-eval-s0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:43:41.449Z\", \"updated_at\": \"2026-05-15T12:43:56.370Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/injected_eval.py --model_path checkpoints/mini_taxei_sft_v4_seed0/v0-20260515-014320/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant taxei --output eval_results/v4_taxei_recovery_eval_s0.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"148014\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-recovery-eval-s0.log\", \"submitted_at\": \"2026-05-15T12:43:56.208Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"v4-vanilla-recovery-eval-s123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:43:39.466Z\", \"updated_at\": \"2026-05-15T12:43:54.104Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/injected_eval.py --model_path checkpoints/mini_vanilla_sft_v4_seed123/v1-20260515-022602/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant vanilla --output eval_results/v4_vanilla_recovery_eval_s123.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"147871\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-recovery-eval-s123.log\", \"submitted_at\": \"2026-05-15T12:43:53.923Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"v4-vanilla-recovery-eval-s0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:43:38.052Z\", \"updated_at\": \"2026-05-15T12:43:52.465Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/injected_eval.py --model_path checkpoints/mini_vanilla_sft_v4_seed0/v0-20260515-014317/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant vanilla --output eval_results/v4_vanilla_recovery_eval_s0.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"147731\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-recovery-eval-s0.log\", \"submitted_at\": \"2026-05-15T12:43:52.289Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"v4-random-fixed-inject50-s123-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:42:34.082Z\", \"updated_at\": \"2026-05-15T11:03:47.011Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject50_s123/v0-20260515-172123/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject50_s123_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"140871\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject50-s123-eval.log\", \"submitted_at\": \"2026-05-15T10:42:33.926Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"injection_ratio\": 0.5, \"method\": \"random\", \"parent\": \"v4-random-fixed-inject50-s123\", \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject50_s123/v0-20260515-172123/checkpoint-1635\", \"eval_data\": \"47 ALFWorld clean tasks\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.702, \"successes\": 33, \"total\": 47}}, \"v4-random-fixed-inject50-s0-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:42:31.691Z\", \"updated_at\": \"2026-05-15T11:03:43.512Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject50_s0/v0-20260515-172121/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject50_s0_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"140731\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject50-s0-eval.log\", \"submitted_at\": \"2026-05-15T10:42:31.544Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"injection_ratio\": 0.5, \"method\": \"random\", \"parent\": \"v4-random-fixed-inject50-s0\", \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject50_s0/v0-20260515-172121/checkpoint-1635\", \"eval_data\": \"47 ALFWorld clean tasks\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.468, \"successes\": 22, \"total\": 47}}, \"v4-taxei-fixed-inject50-s123-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:16:18.413Z\", \"updated_at\": \"2026-05-15T10:42:27.288Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject50_s123/v0-20260515-153737/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject50_s123_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"138352\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject50-s123-eval.log\", \"submitted_at\": \"2026-05-15T10:16:18.279Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.468, \"eval_successes\": 22, \"eval_total\": 47}}, \"v4-taxei-fixed-inject50-s0-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:16:16.102Z\", \"updated_at\": \"2026-05-15T10:42:25.403Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject50_s0/v0-20260515-153735/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject50_s0_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"138210\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject50-s0-eval.log\", \"submitted_at\": \"2026-05-15T10:16:15.945Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.702, \"eval_successes\": 33, \"eval_total\": 47}}, \"v4-random-fixed-inject25-s123-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:28:36.999Z\", \"updated_at\": \"2026-05-15T10:40:52.525Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject25_s123/v0-20260515-173124/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject25_s123_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"139943\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-s123-eval.log\", \"submitted_at\": \"2026-05-15T10:31:06.664Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.511, \"total\": 47, \"successes\": 24, \"by_task\": {\"look_at_obj_in_light\": 0.667, \"pick_and_place_simple\": 0.375, \"pick_clean_then_place_in_recep\": 0.545, \"pick_cool_then_place_in_recep\": 0.143, \"pick_heat_then_place_in_recep\": 0.75, \"pick_two_obj_and_place\": 0.571}}}, \"v4-random-fixed-inject25-s0-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:28:34.789Z\", \"updated_at\": \"2026-05-15T10:40:49.769Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject25_s0/v0-20260515-173122/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject25_s0_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"139405\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-s0-eval.log\", \"submitted_at\": \"2026-05-15T10:28:34.627Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.617, \"total\": 47, \"successes\": 29, \"by_task\": {\"look_at_obj_in_light\": 0.667, \"pick_and_place_simple\": 0.625, \"pick_clean_then_place_in_recep\": 0.455, \"pick_cool_then_place_in_recep\": 0.571, \"pick_heat_then_place_in_recep\": 0.75, \"pick_two_obj_and_place\": 0.714}}}, \"v4-random-fixed-inject25-s123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:37:05.059Z\", \"updated_at\": \"2026-05-15T10:28:27.449Z\", \"hypothesis\": \"D022 multi-seed dose-response: Random 25% injection, seed=123 (fixed 4,358 total). 对标 seed=42 的 55.3%。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --output_dir checkpoints/v4_random_fixed_inject25_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"134594\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-s123.log\", \"submitted_at\": \"2026-05-15T09:31:15.334Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject25-s0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:37:03.696Z\", \"updated_at\": \"2026-05-15T10:28:26.939Z\", \"hypothesis\": \"D022 multi-seed dose-response: Random 25% injection, seed=0 (fixed 4,358 total). 对标 seed=42 的 55.3%。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --output_dir checkpoints/v4_random_fixed_inject25_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"134514\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-s0.log\", \"submitted_at\": \"2026-05-15T09:31:12.733Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject50-s123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:37:07.099Z\", \"updated_at\": \"2026-05-15T10:16:08.482Z\", \"hypothesis\": \"D022 multi-seed dose-response: Random 50% injection, seed=123 (fixed 4,358 total). 对标 seed=42 的 57.4%。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject50.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --output_dir checkpoints/v4_random_fixed_inject50_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"132973\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject50-s123.log\", \"submitted_at\": \"2026-05-15T09:21:14.249Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject50-s0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:37:06.104Z\", \"updated_at\": \"2026-05-15T10:16:07.812Z\", \"hypothesis\": \"D022 multi-seed dose-response: Random 50% injection, seed=0 (fixed 4,358 total). 对标 seed=42 的 57.4%。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject50.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --output_dir checkpoints/v4_random_fixed_inject50_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"132895\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject50-s0.log\", \"submitted_at\": \"2026-05-15T09:21:11.673Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject25-s123-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:21:06.936Z\", \"updated_at\": \"2026-05-15T09:31:06.482Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject25_s123/v0-20260515-153732/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject25_s123_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"132743\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s123-eval.log\", \"submitted_at\": \"2026-05-15T09:21:06.806Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"metrics\": {\"eval_success_rate\": 0.468, \"eval_successes\": 22, \"eval_total\": 47}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject25-s0-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:21:04.275Z\", \"updated_at\": \"2026-05-15T09:31:05.078Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject25_s0/v0-20260515-153729/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject25_s0_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"132601\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s0-eval.log\", \"submitted_at\": \"2026-05-15T09:21:04.135Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"metrics\": {\"eval_success_rate\": 0.468, \"eval_successes\": 22, \"eval_total\": 47}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject50-s123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:37:02.779Z\", \"updated_at\": \"2026-05-15T09:19:37.321Z\", \"hypothesis\": \"D022 multi-seed dose-response: TaxEI 50% injection, seed=123 (fixed 4,358 total). 对标 seed=42 的 51.1%。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject50.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --output_dir checkpoints/v4_taxei_fixed_inject50_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"127437\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject50-s123.log\", \"submitted_at\": \"2026-05-15T07:37:29.012Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4348, \"train_duration_min\": 52.9, \"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358}}, \"v4-taxei-fixed-inject50-s0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:37:01.354Z\", \"updated_at\": \"2026-05-15T09:19:36.235Z\", \"hypothesis\": \"D022 multi-seed dose-response: TaxEI 50% injection, seed=0 (fixed 4,358 total). 对标 seed=42 的 51.1%。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject50.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --output_dir checkpoints/v4_taxei_fixed_inject50_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"127162\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject50-s0.log\", \"submitted_at\": \"2026-05-15T07:37:26.289Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4342, \"train_duration_min\": 52.4, \"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358}}, \"v4-taxei-fixed-inject25-s123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:37:00.336Z\", \"updated_at\": \"2026-05-15T09:19:35.202Z\", \"hypothesis\": \"D022 multi-seed dose-response: TaxEI 25% injection, seed=123 (fixed 4,358 total). 对标 seed=42 的 48.9%。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --output_dir checkpoints/v4_taxei_fixed_inject25_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"126954\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s123.log\", \"submitted_at\": \"2026-05-15T07:37:23.453Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4253, \"train_duration_min\": 55.9, \"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358}}, \"v4-taxei-fixed-inject25-s0\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:36:58.951Z\", \"updated_at\": \"2026-05-15T09:19:33.971Z\", \"hypothesis\": \"D022 multi-seed dose-response: TaxEI 25% injection, seed=0 (fixed 4,358 total). 对标 seed=42 的 48.9%。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --output_dir checkpoints/v4_taxei_fixed_inject25_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"126876\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s0.log\", \"submitted_at\": \"2026-05-15T07:37:20.823Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4258, \"train_duration_min\": 56.1, \"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358}}, \"v4-vanilla-recovery-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:30:18.314Z\", \"updated_at\": \"2026-05-15T03:29:56.077Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant vanilla --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_vanilla_recovery_eval.json\", \"server\": \"autodl-5090\", \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=42)\", \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4/v0-20260514-201441/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks with error injection\", \"seed\": 42, \"parent\": \"mini-vanilla-sft-v4\", \"checkpoint_path\": \"eval_results/v4_vanilla_recovery_eval.json\", \"log_path\": \"eval_results/v4_vanilla_recovery_eval.json\"}, \"hypothesis\": \"v4 Vanilla SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators\", \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.617, \"successes\": 29, \"total\": 47, \"recovery_rate\": 0.617, \"detection_rate\": 0, \"per_operator\": {\"C1_context_truncation\": {\"recovered\": 9, \"total\": 12, \"rate\": 0.75}, \"C4_observation_masking\": {\"recovered\": 6, \"total\": 11, \"rate\": 0.545}, \"P1_step_order_swap\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}, \"P2_sub_goal_deletion\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}}}, \"completed_at\": \"2026-05-14T21:20:15.791Z\"}, \"v4-random-fixed-inject50-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:43:46.913Z\", \"updated_at\": \"2026-05-15T02:03:49.013Z\", \"hypothesis\": \"v4 Random 50% injection fixed-size eval — 47 tasks clean eval. 与 TaxEI 50% (51.1%) 对比。Random dose-response 最后一点。\", \"spec\": {\"gpu\": [\"cuda:3\"]}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:56:26.837Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:56:28.410747+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.574, \"eval_successes\": 27, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -4.3, \"vs_taxei_50_pp\": 6.3}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject50_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject50-eval.log\", \"completed_at\": \"2026-05-15T02:00:22.858Z\"}, \"v4-random-fixed-inject25-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:48:25.777Z\", \"updated_at\": \"2026-05-15T02:03:46.203Z\", \"hypothesis\": \"v4 Random 25% injection fixed-size eval — 47 ALFWorld tasks (clean). 与 TaxEI 25% (48.9%) 对比。\", \"parent\": \"v4-random-fixed-inject25\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject25_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"parent\": \"v4-random-fixed-inject25\", \"checkpoint_source\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"data_path\": \"eval/alfworld_47_clean\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject25)\", \"seed\": 42, \"gpu\": [\"cuda:0\"], \"pid\": \"112516\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25-eval.log\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.553, \"eval_successes\": 26, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -6.4, \"vs_taxei_25_pp\": 6.4}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject25_eval.json\", \"completed_at\": \"2026-05-15T01:59:41.894Z\"}, \"v4-random-fixed-inject50\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:45:08.375Z\", \"updated_at\": \"2026-05-15T02:02:45.338Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 50% injection (4,358 total = 2,179 clean + 2,179 injected). 与 TaxEI 50% 对比 taxonomy 标签在高注入比例下是否有差异。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/random_fixed_inject50/v0-20260515-084528/checkpoint-1635\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:39:15.464Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:39:17.014804+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358, \"train_loss\": 0.4338, \"final_step_loss\": 0.2618, \"token_accuracy\": 0.91, \"train_duration_min\": 53.1, \"memory_gib\": 18, \"train_speed_s_per_it\": 1.95}, \"completed_at\": \"2026-05-15T01:43:35.237Z\"}, \"v4-random-fixed-inject25\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:44.436Z\", \"updated_at\": \"2026-05-15T01:48:07.606Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 25% injection (4,358 total). 与 TaxEI 25% (48.9%) 对比 taxonomy 标签在中等注入比例下是否有差异。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --output_dir checkpoints/v4_random_fixed_inject25 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"gpu\": \"cuda:1\", \"max_steps\": 1635, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject25/v1-20260515-084707/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject25.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:43:59.432Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:44:03.491274+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_steps\": 1635, \"train_epochs\": 3, \"data_count\": 4358}, \"completed_at\": \"2026-05-15T01:48:05.171Z\"}, \"v4-random-fixed-inject10-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:28:17.994Z\", \"updated_at\": \"2026-05-15T01:42:40.302Z\", \"hypothesis\": \"v4 Random 10% injection fixed-size eval — 47 ALFWorld tasks (clean). 与 TaxEI 10% (61.7%) 对比。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_fixed_inject10_eval.json --device cuda:2\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"110187\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-eval.log\", \"submitted_at\": \"2026-05-15T01:28:27.422Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10\", \"checkpoint_source\": \"v4-random-fixed-inject10\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"data_count\": 47, \"data_path\": \"eval/alfworld_47_clean\", \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10)\", \"seed\": 42, \"wall_clock_seconds\": 852.9, \"gpu_hours\": 0.24}, \"parent\": \"v4-random-fixed-inject10\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/v4_random_fixed_inject10_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-eval.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T01:42:40.303Z\"}, \"v4-taxei-fixed-inject50-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:28:14.823Z\", \"updated_at\": \"2026-05-15T01:38:54.383Z\", \"spec\": {\"command\": \"python eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --num_episodes 47 --output eval_results/v4_taxei_fixed_inject50_eval.json --device cuda:0 --seed 42\", \"server\": \"autodl-5090\", \"data_path\": \"ALFWorld valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (v4-taxei-fixed-inject50)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"eval_data\": \"ALFWorld valid_unseen 47 tasks clean eval\"}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 50% injection eval — 47 tasks clean eval. Dose-response 最后一个数据点。已有：0%=61.7%, 10%=61.7%, 25%=48.9%, 50%=待测。\", \"metrics\": {\"eval_success_rate\": 0.511, \"eval_successes\": 24, \"eval_total\": 47, \"vs_vanilla_seed42_pp\": -10.6}, \"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"log_path\": \"/tmp/eval_inject50.log\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T01:37:38.792Z\"}, \"v4-random-fixed-inject10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:41.996Z\", \"updated_at\": \"2026-05-15T01:31:01.715Z\", \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection (4,358 total). 与 TaxEI 10% (61.7%) 对比 taxonomy 标签在低注入比例下是否有差异。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export CUDA_VISIBLE_DEVICES=2 && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --output_dir checkpoints/v4_random_fixed_inject10 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"104655\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10.log\", \"submitted_at\": \"2026-05-15T00:28:19.537Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635\", \"wall_clock_seconds\": 3546.1, \"gpu_hours\": 0.99}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:26:29.568Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:26:31.003606+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4226, \"final_step_loss\": 0.3079, \"token_accuracy\": 0.9, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 57}, \"completed_at\": \"2026-05-15T01:27:25.646Z\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10/v0-20260515-082828/checkpoint-1635\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10.log\"}, \"v4-taxei-fixed-inject50\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:25:38.284Z\", \"updated_at\": \"2026-05-15T01:25:47.611Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 50% injection ratio (4,358 total = 2,179 clean + 2,179 injected). Dose-response 最后一个点，完成后有完整曲线 0%→10%→25%→50%。\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4_fixed_inject50.jsonl --lora_rank 16 --num_train_epochs 3 --seed 42 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --learning_rate 1e-4\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"104236\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject50.log\", \"submitted_at\": \"2026-05-15T00:27:51.219Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject50.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/v4_taxei_fixed_inject50/v0-20260515-082759/checkpoint-1635\", \"wall_clock_seconds\": 3476.4, \"gpu_hours\": 0.97}, \"reproduce\": {\"finished_at\": \"2026-05-15T01:22:23.688Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:22:25.093365+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.259, \"token_accuracy\": 0.911, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 53.1}, \"completed_at\": \"2026-05-15T01:25:47.611Z\"}, \"v4-random-seed123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:14:30.699Z\", \"updated_at\": \"2026-05-15T00:27:24.291Z\", \"hypothesis\": \"v4 Random SFT seed=123 eval — 47 tasks clean eval. Multi-seed: seed=42 66.0%, seed=0 55.3%, seed=123 待测。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export CUDA_VISIBLE_DEVICES=1 && cd /root/autodl-tmp/tax_error_inject_agent && python eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_seed123_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": 102888, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"submitted_at\": \"2026-05-15T00:14:42.930Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"eval_data\": \"47 tasks clean eval (no injection)\", \"parent\": \"v4-random-seed123\", \"tmux_session\": \"v4-random-seed123-eval\", \"log_file\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"wall_clock_seconds\": 740.0, \"gpu_hours\": 0.21}, \"conclusion\": \"negative\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123-eval.log\", \"completed_at\": \"2026-05-15T00:27:02.930Z\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}}, \"v4-taxei-fixed-inject25-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:50:53.016Z\", \"updated_at\": \"2026-05-15T00:14:40.327Z\", \"hypothesis\": \"v4 TaxEI 25% injection fixed-size eval — 48.9% (23/47), 显著低于 vanilla baseline 65.3%（-16.4pp）。Dose-response 数据点。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject25_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"checkpoint_source\": \"output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean)\", \"parent\": \"v4-taxei-fixed-inject25-r2\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject25)\", \"seed\": 42}, \"metrics\": {\"eval_success_rate\": 0.489, \"eval_successes\": 23, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 4, \"total\": 6, \"rate\": 0.667}, \"pick_and_place_simple\": {\"success\": 3, \"total\": 8, \"rate\": 0.375}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 2, \"total\": 7, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"checkpoint_path\": \"eval_results/v4_taxei_fixed_inject25_eval.json\", \"log_path\": \"/tmp/v4_taxei_fixed_inject25_eval.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:30.429Z\"}, \"v4-taxei-fixed-inject10-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:50:52.584Z\", \"updated_at\": \"2026-05-15T00:14:38.874Z\", \"hypothesis\": \"v4 TaxEI 10% injection fixed-size eval — 61.7% (29/47), 低于 vanilla baseline 65.3%（-3.6pp）。Dose-response 数据点。\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_fixed_inject10_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"tmux_session\": \"eval_inject10\", \"checkpoint_source\": \"output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean)\", \"parent\": \"v4-taxei-fixed-inject10\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10)\", \"seed\": 42, \"log_path\": \"/tmp/v4_taxei_fixed_inject10_eval.log\"}, \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"checkpoint_path\": \"eval_results/v4_taxei_fixed_inject10_eval.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:29.992Z\"}, \"v4-taxei-seed123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:44:07.489Z\", \"updated_at\": \"2026-05-15T00:14:37.513Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_seed123_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 100600, \"model_name\": \"Qwen3-8B + LoRA (taxei v4 seed=123)\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-taxei-seed123\", \"checkpoint_path\": \"eval_results/v4_taxei_seed123_eval.json\", \"log_path\": \"/tmp/v4_taxei_seed123_eval.log\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47}, \"hypothesis\": \"v4 TaxEI SFT seed=123 eval — 61.7% (29/47), 低于 vanilla baseline 65.3%（-3.6pp）。multi-seed verification, 9029 samples。\", \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"by_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"success\": 7, \"total\": 11, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:14:29.055Z\"}, \"v4-random-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:49:34.441Z\", \"updated_at\": \"2026-05-14T23:52:15.056Z\", \"hypothesis\": \"v4 Random SFT seed=123 (P1 multi-seed补齐) — 9,029 samples, same hyperparams as seed=42/0, 配齐3-seed统计分析\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_random_v4.jsonl --seed 123 --lora_rank 16 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": 93477, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed123.log\", \"submitted_at\": \"2026-05-14T21:59:16.545Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 6778.5, \"gpu_hours\": 1.88}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:50:09.168Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:50:10.389568+00:00\"}]}, \"metrics\": {\"train_loss\": 0.35484016, \"final_loss\": 0.16766574, \"token_accuracy\": 0.94187103, \"avg_token_accuracy\": 0.90849673, \"train_steps\": 3387, \"train_epochs\": 3, \"train_runtime_sec\": 6609.3556, \"train_duration_min\": 110.2, \"train_samples_per_second\": 4.098, \"train_steps_per_second\": 0.512, \"train_speed_s_per_it\": 1.951, \"memory_gib\": 18.49}, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed123/v0-20260515-055925/checkpoint-3387\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:52:15.056Z\"}, \"v4-taxei-fixed-inject25-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:32:41.837Z\", \"updated_at\": \"2026-05-14T23:50:46.230Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio retry (4,358 total = 3,268 clean + 1,090 injected). 修复 CUDA_VISIBLE_DEVICES，显式设 =3。\", \"spec\": {\"command\": \"export CUDA_VISIBLE_DEVICES=3 && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl --output_dir checkpoints/taxei_fixed_inject25 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": 96835, \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.25, \"clean_count\": 3268, \"injected_count\": 1090, \"log_path\": \"/tmp/v4-fixed-inject25.log\", \"note\": \"manual tmux with explicit CUDA_VISIBLE_DEVICES=3, fixing r1 OOM\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/v4-fixed-inject25/v0-20260515-063144/checkpoint-1635\", \"metrics\": {\"final_loss\": 0.285, \"token_accuracy\": 0.893, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}, \"completed_at\": \"2026-05-14T23:50:46.230Z\"}, \"v4-taxei-fixed-inject10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:52.707Z\", \"updated_at\": \"2026-05-14T23:50:45.829Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio (4,358 total = 3,922 clean + 436 injected). Fixed-size = vanilla 大小，控制数据量变量。Dose-response: 10%/25%/50%。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset sft_taxei_v4_fixed_inject10.jsonl --output_dir output/v4-fixed-inject10 --num_train_epochs 3 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --seed 42 --data_seed 42 --bf16 true --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"94635\", \"log_path\": \"/tmp/v4-fixed-inject10.log\", \"submitted_at\": \"2026-05-15T06:12:34Z\", \"submitted_via\": \"manual_tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.1, \"clean_count\": 3922, \"injected_count\": 436}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/v4-fixed-inject10/v0-20260515-061243/checkpoint-1635\", \"metrics\": {\"final_loss\": 0.308, \"token_accuracy\": 0.888, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}, \"completed_at\": \"2026-05-14T23:50:45.829Z\"}, \"v4-taxei-fixed-inject25\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:53.209Z\", \"updated_at\": \"2026-05-14T23:45:26.890Z\", \"hypothesis\": \"v4 TaxEI fixed-size ablation: 25% injection ratio (4,358 total = 3,268 clean + 1,090 injected). Fixed-size = vanilla 大小，控制数据量变量。Dose-response: 10%/25%/50%。\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset sft_taxei_v4_fixed_inject25.jsonl --output_dir output/v4-fixed-inject25 --num_train_epochs 3 --learning_rate 1e-4 --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --seed 42 --data_seed 42 --bf16 true --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"96835\", \"log_path\": \"/tmp/v4-fixed-inject25.log\", \"submitted_at\": \"2026-05-15T06:31:44Z\", \"submitted_via\": \"manual_tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject25.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"injection_ratio\": 0.25, \"clean_count\": 3268, \"injected_count\": 1090, \"note\": \"r1 (PID 95170) OOM on cuda:0 — submit_training_job failed to pass CUDA_VISIBLE_DEVICES. Resubmitted manually via tmux with explicit export CUDA_VISIBLE_DEVICES=3.\"}, \"conclusion\": \"failed\", \"failure_reason\": \"CUDA_VISIBLE_DEVICES 未生效，模型加载到 cuda:0 导致 OOM（与 seed123 训练冲突）\", \"completed_at\": \"2026-05-14T23:45:26.890Z\"}, \"v4-taxei-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:49:34.191Z\", \"updated_at\": \"2026-05-14T23:43:38.819Z\", \"hypothesis\": \"v4 TaxEI SFT seed=123 (P1 multi-seed补齐) — 9,029 samples, same hyperparams as seed=42/0, 配齐3-seed统计分析\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 123 --lora_rank 16 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 92263, \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed123.log\", \"submitted_at\": \"2026-05-14T21:50:17.845Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 6801.0, \"gpu_hours\": 1.89}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:41:32.774Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:41:33.984355+00:00\"}]}, \"metrics\": {\"final_loss\": 0.35506879, \"token_accuracy\": 0.89978214, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 109.2, \"train_runtime_sec\": 6549.432, \"train_speed_s_per_it\": 1.934, \"memory_gib\": 18.49}, \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed123/v0-20260515-055026/checkpoint-3387\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:43:38.819Z\"}, \"v4-fixed-inject25\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:23.317Z\", \"updated_at\": \"2026-05-14T22:29:19.308Z\", \"spec\": {\"hypothesis\": \"Fixed-size ablation: 25% injection ratio (4,358 total samples, ~1,090 injected + ~3,269 clean). Tests intermediate injection ratio. Combined with 10%/50% results, reveals dose-response curve. Addresses Reviewer Concern #5.\", \"parent\": \"v4-taxei-eval\", \"plan_id\": \"fixed-size-ablation\", \"reviewer_concern\": \"RC5\"}, \"conclusion\": \"killed\", \"failure_reason\": \"duplicate entry — active experiment is v4-taxei-fixed-inject25 (RUNNING)\"}, \"v4-fixed-inject10\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:09:21.673Z\", \"updated_at\": \"2026-05-14T22:29:18.354Z\", \"spec\": {\"hypothesis\": \"Fixed-size ablation: 10% injection ratio (4,358 total samples, ~436 injected + ~3,922 clean). Tests whether low injection ratio still harms clean performance. If yes → injection itself is harmful regardless of ratio. Addresses Reviewer Concern #5.\", \"parent\": \"v4-taxei-eval\", \"plan_id\": \"fixed-size-ablation\", \"reviewer_concern\": \"RC5\"}, \"conclusion\": \"killed\", \"failure_reason\": \"duplicate entry — active experiment is v4-taxei-fixed-inject10 (RUNNING)\"}, \"v4-random-recovery-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:04:57.591Z\", \"updated_at\": \"2026-05-14T22:00:43.285Z\", \"hypothesis\": \"v4 Random SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators. Phase 2 counterpart to vanilla/taxei recovery eval.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/injected_eval.py --model_path checkpoints/mini_random_sft_v4/v1-20260514-213104/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant random --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_recovery_eval.json\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 90124, \"model_name\": \"Qwen3-8B + LoRA (random SFT v4)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4/v1-20260514-213104/checkpoint-3387\", \"eval_data\": \"valid_unseen (47 episodes)\", \"log_path\": \"/tmp/v4_random_recovery_eval.log\", \"output_path\": \"eval_results/v4_random_recovery_eval.json\", \"data_path\": \"valid_unseen\", \"data_count\": 47}, \"conclusion\": \"success\", \"checkpoint_path\": \"eval_results/v4_random_recovery_eval.json\", \"completed_at\": \"2026-05-14T21:42:07.544Z\", \"metrics\": {\"recovery_rate\": 0.638, \"detection_rate\": 0, \"successes\": 30, \"total\": 47, \"source\": \"json-file-verified\", \"note\": \"r1=29/47, r2=30/47, ±2pp run-to-run variance on P1 non-determinism\"}}, \"v4-taxei-recovery-eval-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:23:55.110Z\", \"updated_at\": \"2026-05-14T21:46:19.993Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python3 eval/injected_eval.py --model_path checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant taxei --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_recovery_eval_r2.json\", \"server\": \"autodl-5090\", \"model_name\": \"Qwen3-8B + LoRA (mini_taxei_sft_v4 checkpoint-3387)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387\", \"eval_data\": \"47 episodes with error injection (4 operators: C1_context_truncation, C4_observation_masking, P1_step_order_swap, P2_sub_goal_deletion)\", \"data_path\": \"eval/injected_eval.py\", \"data_count\": 47, \"hypothesis\": \"v4 TaxEI SFT seed=42 recovery eval retry — 47 episodes with error injection, measuring detection/recovery/success rates. Previous attempt reported process dead 5x.\", \"pid\": 90519, \"log_path\": \"/tmp/v4_taxei_recovery_eval_r2.log\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"eval_results/v4_taxei_recovery_eval_r2.json\", \"completed_at\": \"2026-05-14T21:42:08.000Z\", \"metrics\": {\"recovery_rate\": 0.596, \"detection_rate\": 0, \"total_episodes\": 47, \"per_operator\": {\"C1_context_truncation\": {\"recovered\": 8, \"total\": 12, \"rate\": 0.667}, \"C4_observation_masking\": {\"recovered\": 7, \"total\": 11, \"rate\": 0.636}, \"P1_step_order_swap\": {\"recovered\": 7, \"total\": 12, \"rate\": 0.583}, \"P2_sub_goal_deletion\": {\"recovered\": 6, \"total\": 12, \"rate\": 0.5}}}}, \"v4-taxei-seed0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:30:26.278Z\", \"updated_at\": \"2026-05-14T21:21:53.154Z\", \"hypothesis\": \"v4 TaxEI SFT seed=0 eval — multi-seed verification, 9029 samples, testing TaxEI injection stability\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed0/v0-20260515-014320/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_seed0_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei v4 seed=0)\", \"seed\": 0, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4_seed0/v0-20260515-014320/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-taxei-seed0\", \"checkpoint_path\": \"eval_results/v4_taxei_seed0_eval.json\", \"log_path\": \"eval_results/v4_taxei_seed0_eval.log\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.468, \"eval_successes\": 22, \"eval_total\": 47, \"vs_seed42_pp\": -14.9}, \"completed_at\": \"2026-05-14T21:20:13.351Z\"}, \"v4-random-seed0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:30:26.456Z\", \"updated_at\": \"2026-05-14T21:21:52.271Z\", \"hypothesis\": \"v4 Random SFT seed=0 eval — multi-seed verification, 9029 samples, testing random injection stability\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed0/v0-20260515-014329/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_seed0_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random v4 seed=0)\", \"seed\": 0, \"checkpoint_source\": \"checkpoints/mini_random_sft_v4_seed0/v0-20260515-014329/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-random-seed0\", \"log_path\": \"eval_results/v4_random_seed0_eval.log\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.553, \"eval_successes\": 26, \"eval_total\": 47, \"vs_seed42_pp\": -10.7}, \"checkpoint_path\": \"eval_results/v4_random_seed0_eval.json\", \"completed_at\": \"2026-05-14T21:20:14.339Z\"}, \"v4-taxei-recovery-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T20:40:41.154Z\", \"updated_at\": \"2026-05-14T21:20:17.664Z\", \"spec\": {\"hypothesis\": \"D010 Phase 2: Recovery eval with action injection on TaxEI seed=42 checkpoint — measuring TaxEI-trained model's recovery ability vs vanilla\", \"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/injected_eval.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --model_variant taxei --device cuda:0 --seed 42 --output eval_results/v4_taxei_recovery_eval.json\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": 87614, \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + TaxEI LoRA v4 checkpoint-3387\", \"seed\": 42, \"checkpoint_source\": \"mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387\", \"eval_data\": \"ALFWorld valid_unseen 47 tasks with action injection\", \"checkpoint_path\": \"eval_results/v4_taxei_recovery_eval.json\", \"log_path\": \"/root/runs/tax_error_inject_agent/v4-taxei-recovery-eval.log\"}, \"hypothesis\": \"v4 TaxEI SFT seed=42 recovery eval (injected_eval.py) — 47 episodes with error injection, measuring detection/recovery/success rates under P1/P2/C1/C4 operators. Phase 2 counterpart to vanilla recovery eval.\", \"reproduce\": {\"finished_at\": \"2026-05-14T20:58:38.335Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T20:58:38.665Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T20:58:39.601019+00:00\"}]}, \"metrics\": {\"success_rate\": 0.596, \"successes\": 28, \"total\": 47, \"recovery_rate\": 0.596, \"detection_rate\": 0}}, \"v4-vanilla-seed123-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:30:26.635Z\", \"updated_at\": \"2026-05-14T20:43:48.780Z\", \"hypothesis\": \"v4 Vanilla SFT seed=123 eval — multi-seed verification, 4358 samples, comparing with seed=42 baseline (61.7%)\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed123/v1-20260515-022602/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_vanilla_seed123_eval.json --device cuda:0\", \"server\": \"autodl-5090\", \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=123)\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4_seed123/v1-20260515-022602/checkpoint-1635\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_vanilla_sft_v4_seed123/v1-20260515-022602/checkpoint-1635\", \"log_path\": \"/tmp/v4_vanilla_seed123_eval.log\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-vanilla-seed123\", \"data_path\": \"eval/valid_unseen\", \"data_count\": 47}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T20:37:11.382Z\", \"metrics\": {\"eval_success_rate\": 0.66, \"eval_successes\": 31, \"eval_total\": 47, \"vs_seed42_pp\": 4.3, \"vs_seed0_pp\": -2.1, \"per_task\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 6, \"total\": 8, \"rate\": 0.75}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 7, \"total\": 8, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}}, \"v4-random-seed0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:42:03.440Z\", \"updated_at\": \"2026-05-14T19:36:31.263Z\", \"hypothesis\": \"v4 Random SFT seed=0 (multi-seed verification) — 9,029 samples, same hyperparams as seed=42, testing result stability\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"server\": \"autodl-5090\", \"command\": \"swift sft --model Qwen3-8B --dataset sft_random_v4.jsonl --seed 0\", \"gpu\": \"cuda:2\", \"pid\": 72303, \"log_path\": \"/root/runs/tax_error_inject_agent/v4-random-seed0.log\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed0/v0-20260515-014329/checkpoint-3387\"}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.355, \"token_accuracy\": 0.912, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 110}, \"completed_at\": \"2026-05-14T19:35:39.420Z\"}, \"v4-taxei-seed0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:42:02.696Z\", \"updated_at\": \"2026-05-14T19:36:29.716Z\", \"hypothesis\": \"v4 TaxEI SFT seed=0 (multi-seed verification) — 9,029 samples, same hyperparams as seed=42, testing result stability\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"server\": \"autodl-5090\", \"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 0\", \"gpu\": \"cuda:1\", \"pid\": 71822, \"log_path\": \"/root/runs/tax_error_inject_agent/v4-taxei-seed0.log\", \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed0/v0-20260515-014320/checkpoint-3387\"}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.355, \"token_accuracy\": 0.917, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 110}, \"completed_at\": \"2026-05-14T19:35:37.503Z\"}, \"v4-vanilla-seed0-eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:30:26.093Z\", \"updated_at\": \"2026-05-14T19:30:45.170Z\", \"hypothesis\": \"v4 Vanilla SFT seed=0 eval — multi-seed verification, 4358 samples, comparing with seed=42 baseline (61.7%)\", \"spec\": {\"checkpoint_path\": \"eval_results/v4_vanilla_seed0_eval.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-seed0-eval.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T19:01:19.696Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T19:01:20.697938+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.681, \"eval_successes\": 32, \"eval_total\": 47, \"vs_seed42_pp\": 6.4, \"mcnemar_vs_seed42_p\": 0.375, \"discordant_pairs\": 5, \"per_task\": {\"look_at_obj_in_light\": \"5/6 (83.3%)\", \"pick_and_place_simple\": \"5/8 (62.5%)\", \"pick_clean_then_place\": \"6/11 (54.5%)\", \"pick_cool_then_place\": \"4/7 (57.1%)\", \"pick_heat_then_place\": \"7/8 (87.5%)\", \"pick_two_obj_and_place\": \"5/7 (71.4%)\"}}, \"completed_at\": \"2026-05-14T19:29:37.198Z\"}, \"v4-vanilla-seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:45:23.836Z\", \"updated_at\": \"2026-05-14T19:29:24.021Z\", \"hypothesis\": \"D010 Phase 1: v4 Vanilla SFT seed=123 多种子验证 — 4,358 samples, LoRA rank=16, 3 epochs, 与 seed=42 的 61.7% 对比波动范围\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_vanilla_v4.jsonl --output_dir checkpoints/mini_vanilla_sft_v4_seed123 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 123 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": 77937, \"log_path\": \"checkpoints/mini_vanilla_sft_v4_seed123/v1-20260515-022602/logging.jsonl\", \"submitted_at\": \"2026-05-14T18:20:42.388Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/sft_vanilla_v4.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"checkpoints/mini_vanilla_sft_v4_seed123\", \"note\": \"OOM on first attempt (v0), restarted as v1 with PID 77937\", \"wall_clock_seconds\": 3941.6, \"gpu_hours\": 1.09}, \"reproduce\": {\"finished_at\": \"2026-05-14T19:26:23.312Z\"}, \"failure_reason\": \"v0 OOM at model loading (GPU 3 occupied by another process, 18.21 GiB in use). v1 (PID 77937) actually completed 1635/1635 steps. Cron caught v0's EXIT_CODE=1. Verifying checkpoint validity...\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T19:26:23.949Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T19:26:24.909318+00:00\"}]}, \"metrics\": {\"final_loss\": 0.288, \"token_accuracy\": 0.903, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58.9}}, \"v4-vanilla-seed0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:42:01.929Z\", \"updated_at\": \"2026-05-14T18:46:58.919Z\", \"hypothesis\": \"D010 Phase 1: v4 Vanilla SFT seed=0 多种子验证 — 4,358 samples, LoRA rank=16, 3 epochs, 与 seed=42 的 61.7% 对比波动范围\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/sft_vanilla_v4.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"server\": \"autodl-5090\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=0 swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_vanilla_v4.jsonl --output_dir checkpoints/mini_vanilla_sft_v4_seed0 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 0 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\", \"gpu\": \"cuda:0\", \"pid\": 71959, \"log_path\": \"checkpoints/mini_vanilla_sft_v4_seed0/v0-20260515-014317/logging.jsonl\", \"checkpoint_path\": \"checkpoints/mini_vanilla_sft_v4_seed0/v0-20260515-014317/checkpoint-1635\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T18:42:56.365Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T18:42:57.338365+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.297, \"avg_loss\": 0.416, \"token_accuracy\": 0.902, \"train_steps\": 1635, \"train_epochs\": 3, \"train_duration_min\": 58}, \"completed_at\": \"2026-05-14T18:45:18.121Z\"}, \"v4-recovery-eval-dev\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:42:04.153Z\", \"updated_at\": \"2026-05-14T18:15:59.630Z\", \"hypothesis\": \"Recovery eval pipeline development — inject errors during eval to test if TaxEI models recover better than random/vanilla (Option C from D009)\", \"conclusion\": \"success\", \"metrics\": {\"pipeline_files\": [\"eval/injected_eval.py\", \"scripts/run_injected_eval.sh\"], \"injected_eval_lines\": 463, \"dryrun_result\": \"PASS\", \"dryrun_detail\": \"vanilla checkpoint, 1 task, cuda:3, injected error recovered in 13 steps\"}}, \"v4-recovery-dryrun\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:45:26.420Z\", \"updated_at\": \"2026-05-14T18:15:56.604Z\", \"hypothesis\": \"D010 Phase 2 前置: Recovery eval --inject 模式 dry-run, 1-2 tasks 验证 pipeline 正常工作\", \"conclusion\": \"success\"}, \"v4-random-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T16:25:02.397Z\", \"updated_at\": \"2026-05-14T17:31:46.657Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CKPT=checkpoints/mini_random_sft_v4/v1-20260514-213104/checkpoint-3387 && test -f \\\\${CKPT}/adapter_config.json && echo 'adapter_config OK' || { echo 'ERROR: adapter_config.json missing'; exit 1; } && echo 'Using checkpoint: '\\\\$CKPT && CUDA_VISIBLE_DEVICES=1 python3 eval/recovery.py --model_path \\\\$CKPT --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_random_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"67837\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-eval.log\", \"submitted_at\": \"2026-05-14T16:25:02.357Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"v4 Random SFT eval — formal Gate 3b judgment, same-source 9,029 samples, checkpoint-3387\", \"conclusion\": \"negative\", \"metrics\": {\"eval_success_rate\": 0.66, \"eval_successes\": 31, \"eval_total\": 47, \"vs_vanilla_pp\": 4.3, \"vs_taxei_pp\": 4.3, \"mcnemar_vs_vanilla_p\": 0.754, \"per_task\": {\"look_at_obj_in_light\": \"6/6 (100%)\", \"pick_and_place_simple\": \"4/8 (50%)\", \"pick_clean_then_place\": \"6/11 (54.5%)\", \"pick_cool_then_place\": \"4/7 (57.1%)\", \"pick_heat_then_place\": \"7/8 (87.5%)\", \"pick_two_obj_and_place\": \"4/7 (57.1%)\"}}}, \"v4-taxei-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T16:25:00.653Z\", \"updated_at\": \"2026-05-14T17:31:43.481Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CKPT=checkpoints/mini_taxei_sft_v4/v1-20260514-213102/checkpoint-3387 && test -f \\\\${CKPT}/adapter_config.json && echo 'adapter_config OK' || { echo 'ERROR: adapter_config.json missing'; exit 1; } && echo 'Using checkpoint: '\\\\$CKPT && CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path \\\\$CKPT --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_taxei_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"67694\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-eval.log\", \"submitted_at\": \"2026-05-14T16:25:00.616Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"v4 TaxEI SFT eval — formal Gate 3a/3b judgment, same-source 9,029 samples, checkpoint-3387\", \"conclusion\": \"negative\", \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"vs_vanilla_pp\": 0, \"vs_random_pp\": -4.3, \"mcnemar_vs_vanilla_p\": 1, \"mcnemar_vs_random_p\": 0.754, \"gate_3a\": \"FAIL\", \"gate_3b\": \"FAIL\", \"gate_4\": \"PASS\", \"per_task\": {\"look_at_obj_in_light\": \"6/6 (100%)\", \"pick_and_place_simple\": \"5/8 (62.5%)\", \"pick_clean_then_place\": \"6/11 (54.5%)\", \"pick_cool_then_place\": \"3/7 (42.9%)\", \"pick_heat_then_place\": \"7/8 (87.5%)\", \"pick_two_obj_and_place\": \"2/7 (28.6%)\"}}}, \"traj_collect_500\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T06:45:21.504Z\", \"updated_at\": \"2026-05-14T16:28:02.238Z\", \"spec\": {\"command\": \"python collect_trajectories.py --target 500\", \"server\": \"autodl-5090\", \"data_path\": \"data/trajectories/\", \"data_count\": 575, \"model_name\": \"trajectory_collector\", \"seed\": 0, \"pid\": 11045, \"gpu\": \"none (CPU task)\", \"hypothesis\": \"GPT-5.2 可作为 teacher 在 ALFWorld 中收集高质量成功轨迹（预期成功率≥93%）\"}, \"metrics\": {\"successful_trajectories\": 501, \"failed_trajectories\": 213, \"total_attempts\": 714, \"success_rate\": 0.702, \"api_cost_usd\": 8.86, \"collection_time_sec\": 5245}, \"conclusion\": \"negative\", \"checkpoint_path\": \"data/trajectories/successful_trajectories.jsonl\", \"log_path\": \"/tmp/collect_500.log\", \"completed_at\": \"2026-05-14T12:21:11.941Z\"}, \"v4-vanilla-eval-r3\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:28:24.833Z\", \"updated_at\": \"2026-05-14T16:25:11.284Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && latest_run=\\\\$(ls -dt checkpoints/mini_vanilla_sft_v4/v0-*/ | head -1) && final_ckpt=\\\\$(ls -d \\\\\\\"\\\\${latest_run}\\\\\\\"checkpoint-* | sort -V | tail -1) && echo \\\\\\\"Using checkpoint: \\\\$final_ckpt\\\\\\\" && test -f \\\\\\\"\\\\${final_ckpt}/adapter_config.json\\\\\\\" && echo 'adapter_config.json OK' || { echo 'ERROR: adapter_config.json missing'; exit 1; } && CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path \\\\$final_ckpt --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_vanilla_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"62340\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-eval-r3.log\", \"submitted_at\": \"2026-05-14T14:28:24.797Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"v4 Vanilla SFT eval r3 — dynamic checkpoint lookup with sort -V, adapter_config.json pre-check\", \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.617, \"eval_successes\": 29, \"eval_total\": 47, \"per_task\": {\"look_at_obj_in_light\": \"5/6 (83.3%)\", \"pick_heat_then_place\": \"6/8 (75.0%)\", \"pick_and_place_simple\": \"5/8 (62.5%)\", \"pick_cool_then_place\": \"4/7 (57.1%)\", \"pick_two_obj_and_place\": \"4/7 (57.1%)\", \"pick_clean_then_place\": \"5/11 (45.5%)\"}}}, \"v4-vanilla-eval-r2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:24:25.560Z\", \"updated_at\": \"2026-05-14T14:28:40.995Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4/v0-20260514-122641/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_vanilla_eval.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"61793\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-eval-r2.log\", \"submitted_at\": \"2026-05-14T14:24:25.523Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"v4 Vanilla SFT eval retry — fixed --device cuda:0 (was --gpu 0) + explicit checkpoint-1635\", \"conclusion\": \"failed\"}, \"v4-random-sft-r2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:30:55.117Z\", \"updated_at\": \"2026-05-14T14:24:56.155Z\", \"spec\": {\"pid\": \"58163\", \"actual_status\": \"training_in_progress\", \"gpu\": [\"cuda:3\"], \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"hypothesis\": \"v4 Random SFT retry (r2) — same-source 9,029 samples, formal Gate 3b. Previous run killed by SIGHUP.\", \"conclusion\": \"success\"}, \"v4-taxei-sft-r2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:30:52.865Z\", \"updated_at\": \"2026-05-14T14:24:54.288Z\", \"spec\": {\"pid\": \"58034\", \"actual_status\": \"training_in_progress\", \"gpu\": [\"cuda:2\"], \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"hypothesis\": \"v4 TaxEI SFT retry (r2) — same-source 9,029 samples, formal Gate 3a/3b. Previous run killed by SIGHUP.\", \"conclusion\": \"success\"}, \"v4-vanilla-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:15:59.327Z\", \"updated_at\": \"2026-05-14T14:24:25.638Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CKPT=\\\\$(find checkpoints/mini_vanilla_sft_v4 -name 'checkpoint-*' -type d | sort -t- -k2 -n | tail -1) && echo \\\\\\\"Using checkpoint: \\\\$CKPT\\\\\\\" && CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path \\\\$CKPT --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v4_vanilla_eval.json --gpu 0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"61138\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-eval.log\", \"submitted_at\": \"2026-05-14T14:15:59.291Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"v4 Vanilla SFT eval (4,358 samples, clean only) — v4 baseline for Gate 3a comparison\", \"conclusion\": \"failed\"}, \"v3-random-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:26:26.315Z\", \"updated_at\": \"2026-05-14T14:15:26.311Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=1 python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v3/*/checkpoint-3405 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v3_random.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"55925\", \"log_path\": \"~/runs/tax_error_inject_agent/v3-random-eval.log\", \"submitted_at\": \"2026-05-14T13:26:53.024Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"v3 Random SFT eval on 47-task ALFWorld (format-aligned, initial signal before v4 formal judgment)\", \"metrics\": {\"eval_success_rate\": 0.511, \"eval_successes\": 24, \"eval_total\": 47, \"vs_baseline_pp\": 8.5, \"vs_vanilla_sft_pp\": -23.4}, \"conclusion\": \"negative\"}, \"v3-taxei-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:26:24.552Z\", \"updated_at\": \"2026-05-14T14:15:25.974Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v3/*/checkpoint-2832 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v3_taxei.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"55848\", \"log_path\": \"~/runs/tax_error_inject_agent/v3-taxei-eval.log\", \"submitted_at\": \"2026-05-14T13:26:51.905Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"v3 TaxEI SFT eval on 47-task ALFWorld (format-aligned, initial signal before v4 formal judgment)\", \"metrics\": {\"eval_success_rate\": 0.66, \"eval_successes\": 31, \"eval_total\": 47, \"vs_baseline_pp\": 23.4, \"vs_vanilla_sft_pp\": -8.5, \"per_task\": {\"look_at_obj_in_light\": \"5/6 (83.3%)\", \"pick_clean_then_place\": \"8/11 (72.7%)\", \"pick_heat_then_place\": \"6/8 (75.0%)\", \"pick_and_place_simple\": \"5/8 (62.5%)\", \"pick_two_obj_and_place\": \"4/7 (57.1%)\", \"pick_cool_then_place\": \"3/7 (42.9%)\"}}, \"conclusion\": \"negative\"}, \"v4-random-sft-r3\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:32:26.753Z\", \"updated_at\": \"2026-05-14T13:32:36.181Z\", \"spec\": {\"command\": \"bash -c \\\"trap '' HUP; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=3 swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_random_v4.jsonl --output_dir checkpoints/mini_random_sft_v4 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"58826\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-sft-r3.log\", \"submitted_at\": \"2026-05-14T13:32:26.722Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"v4 Random SFT retry (r3) — added trap '' HUP to survive tmux cleanup. Same-source 9,029 samples.\"}, \"v4-taxei-sft-r3\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:32:24.446Z\", \"updated_at\": \"2026-05-14T13:32:34.819Z\", \"spec\": {\"command\": \"bash -c \\\"trap '' HUP; source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=2 swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_taxei_v4.jsonl --output_dir checkpoints/mini_taxei_sft_v4 --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"58741\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-sft-r3.log\", \"submitted_at\": \"2026-05-14T13:32:24.415Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"v4 TaxEI SFT retry (r3) — added trap '' HUP to survive tmux cleanup. Same-source 9,029 samples.\"}, \"v4-random-sft\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:26:31.864Z\", \"updated_at\": \"2026-05-14T13:31:19.378Z\", \"spec\": {\"pid\": \"56765\", \"gpu_memory_mib\": 19159, \"gpu_util_pct\": 60}, \"hypothesis\": \"v4 Random SFT with same-source data (9,029 samples), formal Gate 3b judgment — only tag differs from v4-taxei\", \"conclusion\": \"failed\"}, \"v4-taxei-sft\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:26:29.177Z\", \"updated_at\": \"2026-05-14T13:31:18.431Z\", \"spec\": {\"pid\": \"56685\", \"gpu_memory_mib\": 30884, \"gpu_util_pct\": 94}, \"hypothesis\": \"v4 TaxEI SFT with same-source data (9,029 samples), formal Gate 3a/3b judgment\", \"conclusion\": \"failed\"}, \"mini-vanilla-sft-v4\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:14:26.614Z\", \"updated_at\": \"2026-05-14T13:27:05.003Z\", \"hypothesis\": \"Vanilla SFT baseline with aligned format (v4), for Gate 3a comparison\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_vanilla_v4.jsonl --output_dir checkpoints/mini_vanilla_sft_v4/ --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"50537\", \"log_path\": \"~/runs/tax_error_inject_agent/mini-vanilla-sft-v4.log\", \"submitted_at\": \"2026-05-14T12:14:32.528Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\"}, \"mini-random-sft-v3\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:13:19.635Z\", \"updated_at\": \"2026-05-14T13:27:04.310Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v3/sft_random_aligned.jsonl --output_dir checkpoints/mini_random_sft_v3/ --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"45764\", \"log_path\": \"~/runs/tax_error_inject_agent/mini-random-sft-v3.log\", \"submitted_at\": \"2026-05-14T11:13:19.618Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"metrics\": {\"train_samples\": 9076, \"train_samples_clean\": 4176, \"train_samples_injected\": 4900, \"train_steps_total\": 3405, \"est_duration_min\": 110, \"format\": \"aligned_single_turn\"}, \"conclusion\": \"success\"}, \"mini-taxei-sft-v3\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:13:17.286Z\", \"updated_at\": \"2026-05-14T13:27:03.840Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v3/sft_taxei_aligned.jsonl --output_dir checkpoints/mini_taxei_sft_v3/ --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"45621\", \"log_path\": \"~/runs/tax_error_inject_agent/mini-taxei-sft-v3.log\", \"submitted_at\": \"2026-05-14T11:13:17.271Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"metrics\": {\"train_samples\": 7545, \"train_samples_clean\": 4176, \"train_samples_injected\": 3369, \"train_steps_total\": 2832, \"est_duration_min\": 90, \"format\": \"aligned_single_turn\"}, \"conclusion\": \"success\"}, \"mini-vanilla-sft-v3\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:13:13.990Z\", \"updated_at\": \"2026-05-14T13:27:02.899Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v3/sft_vanilla_aligned.jsonl --output_dir checkpoints/mini_vanilla_sft_v3/ --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"45478\", \"log_path\": \"~/runs/tax_error_inject_agent/mini-vanilla-sft-v3.log\", \"submitted_at\": \"2026-05-14T11:13:13.975Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"metrics\": {\"train_samples\": 4176, \"train_steps_total\": 1566, \"est_duration_min\": 58, \"format\": \"aligned_single_turn\"}, \"conclusion\": \"success\"}, \"v3-vanilla-eval\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:22:10.941Z\", \"updated_at\": \"2026-05-14T13:27:01.957Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_vanilla_sft_v3/v0-20260514-191323/checkpoint-1566 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --output eval_results/v3_vanilla.json --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"51848\", \"log_path\": \"~/runs/tax_error_inject_agent/v3-vanilla-eval.log\", \"submitted_at\": \"2026-05-14T12:22:30.589Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.745, \"successes\": 35, \"total\": 47, \"vs_baseline_pp\": 31.9, \"vs_baseline\": \"42.6% → 74.5%\"}}, \"v4-vanilla-sft\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:14:57.794Z\", \"updated_at\": \"2026-05-14T12:22:10.869Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_vanilla_v4.jsonl --output_dir checkpoints/v4_vanilla_sft/ --lora_rank 16 --lora_alpha 32 --lora_dropout 0.05 --target_modules all-linear --per_device_train_batch_size 1 --gradient_accumulation_steps 8 --max_length 4096 --num_train_epochs 3 --learning_rate 1e-4 --seed 42 --torch_dtype bfloat16 --logging_steps 5 --save_strategy epoch --gradient_checkpointing true\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": 50972, \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-sft.log\", \"submitted_at\": \"2026-05-14T12:14:57.755Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"OOM - CUDA_VISIBLE_DEVICES not set, ran on wrong GPU (cuda:0 instead of cuda:3)\"}, \"conclusion\": \"failed\"}, \"vanilla_sft_aligned_v2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:05:05.459Z\", \"updated_at\": \"2026-05-14T11:05:05.459Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=2 swift sft \\\\\\n  --model /root/autodl-tmp/models/Qwen/Qwen3-8B \\\\\\n  --dataset data/mini_pipeline/sft_vanilla_aligned.jsonl \\\\\\n  --lora_rank 16 \\\\\\n  --lora_alpha 32 \\\\\\n  --lora_dropout 0.05 \\\\\\n  --target_modules all-linear \\\\\\n  --num_train_epochs 1 \\\\\\n  --learning_rate 1e-4 \\\\\\n  --per_device_train_batch_size 1 \\\\\\n  --gradient_accumulation_steps 16 \\\\\\n  --warmup_ratio 0.05 \\\\\\n  --seed 42 \\\\\\n  --max_length 4096 \\\\\\n  --gradient_checkpointing true \\\\\\n  --output_dir checkpoints/vanilla_sft_aligned \\\\\\n  --logging_steps 5 \\\\\\n  --logging_first_step true \\\\\\n  --save_strategy epoch \\\\\\n  --bf16 true \\\\\\n  --weight_decay 0.1 \\\\\\n  --adam_beta1 0.9 \\\\\\n  --adam_beta2 0.95 \\\\\\n  --max_grad_norm 1.0 \\\\\\n  --lr_scheduler_type cosine \\\\\\n  --optim adamw_torch_fused 2>&1\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"44492\", \"log_path\": \"~/runs/tax_error_inject_agent/vanilla_sft_aligned_v2.log\", \"submitted_at\": \"2026-05-14T11:05:05.434Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"vanilla_sft_aligned_v1\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:04:12.825Z\", \"updated_at\": \"2026-05-14T11:04:12.825Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=2 swift sft --config configs/sft_vanilla_aligned.yaml 2>&1\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"43894\", \"log_path\": \"~/runs/tax_error_inject_agent/vanilla_sft_aligned_v1.log\", \"submitted_at\": \"2026-05-14T11:04:12.812Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"mini-vanilla-sft\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:51:41.382Z\", \"updated_at\": \"2026-05-14T10:54:48.860Z\", \"hypothesis\": \"Vanilla trajectory SFT baseline for comparison with TaxEI\", \"spec\": {\"command\": \"python3 scripts/train_sft.py --data data/sft_data/vanilla_train.jsonl --output checkpoints/mini_vanilla_sft/ --model Qwen3-8B --lora_rank 16 --seed 42 --epochs 3 --lr 1e-4\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": \"41874\", \"log_path\": \"eval_results/mini_vanilla_clean.json\", \"submitted_at\": \"2026-05-14T10:54:31.029Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/sft_data/vanilla_train.jsonl\", \"data_count\": 278, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"hypothesis\": \"Vanilla SFT on clean trajectories as baseline for comparison\", \"checkpoint_path\": \"checkpoints/mini_vanilla_sft/v0-20260514-181708/checkpoint-54\", \"wall_clock_seconds\": 17.8, \"gpu_hours\": 0.0}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T10:54:20.210Z\", \"metrics\": {\"eval_success_rate\": 0.149, \"eval_successes\": 7, \"eval_total\": 47, \"vs_baseline_pp\": -27.7, \"per_task\": {\"look_at_obj_in_light\": \"0/6 (0%)\", \"pick_and_place_simple\": \"2/8 (25.0%)\", \"pick_clean_then_place\": \"2/11 (18.2%)\", \"pick_cool_then_place\": \"0/7 (0%)\", \"pick_heat_then_place\": \"3/8 (37.5%)\", \"pick_two_obj_and_place\": \"0/7 (0%)\"}, \"train_steps\": 54, \"train_duration_min\": 5}}, \"mini-taxei-sft\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:51:40.784Z\", \"updated_at\": \"2026-05-14T10:54:46.174Z\", \"hypothesis\": \"TaxEI injection + recovery SFT improves over vanilla SFT on ALFWorld 47-task eval\", \"spec\": {\"command\": \"python3 scripts/train_sft.py --data data/sft_data/taxei_train.jsonl --output checkpoints/mini_taxei_sft/ --model Qwen3-8B --lora_rank 16 --seed 42 --epochs 3 --lr 1e-4\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"41263\", \"log_path\": \"eval_results/mini_taxei_clean.json\", \"submitted_at\": \"2026-05-14T10:53:16.579Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/sft_data/taxei_train.jsonl\", \"data_count\": 278, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/mini_taxei_sft/v0-20260514-181630/checkpoint-195\", \"hypothesis\": \"TaxEI error injection + recovery SFT improves over vanilla SFT and baseline\", \"wall_clock_seconds\": 63.1, \"gpu_hours\": 0.04}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T10:54:19.721Z\", \"metrics\": {\"eval_success_rate\": 0.447, \"eval_successes\": 21, \"eval_total\": 47, \"vs_baseline_pp\": 2.1, \"per_task\": {\"look_at_obj_in_light\": \"3/6 (50.0%)\", \"pick_and_place_simple\": \"2/8 (25.0%)\", \"pick_clean_then_place\": \"6/11 (54.5%)\", \"pick_cool_then_place\": \"1/7 (14.3%)\", \"pick_heat_then_place\": \"6/8 (75.0%)\", \"pick_two_obj_and_place\": \"3/7 (42.9%)\"}, \"train_steps\": 195, \"train_duration_min\": 16.3}}, \"vanilla-react-baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:20:00.119Z\", \"updated_at\": \"2026-05-14T10:54:35.171Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path /root/autodl-tmp/models/Qwen/Qwen3-8B --eval_split valid_unseen --no_inject (MAX_STEPS=50 hardcoded)\", \"server\": \"autodl-5090\", \"data_path\": \"ALFWorld valid_unseen (47/85 tasks, solvable=True filter, pick_and_place_with_movable_recep excluded 0/11)\", \"data_count\": 47, \"model_name\": \"Qwen3-8B (zero-shot, enable_thinking=False)\", \"seed\": 42, \"gpu\": \"cuda:1\", \"hypothesis\": \"Qwen3-8B zero-shot ReAct 在 ALFWorld valid_unseen 的基线成功率，作为 SFT 对比的 lower bound\", \"checkpoint_path\": \"N/A (zero-shot, no training)\", \"log_path\": \"/root/autodl-tmp/tax_error_inject_agent/eval_results/vanilla_react_baseline.json\"}, \"conclusion\": \"success\", \"metrics\": {\"overall_success_rate\": 0.426, \"total_tasks\": 47, \"successes\": 20, \"per_task_type\": {\"pick_heat_then_place\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"look_at_obj_in_light\": {\"success\": 3, \"total\": 6, \"rate\": 0.5}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_two_obj_and_place\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}, \"pick_cool_then_place\": {\"success\": 0, \"total\": 7, \"rate\": 0}}}, \"completed_at\": \"2026-05-14T08:58:00.892Z\"}, \"mini-pipeline-e2e\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:39:15.654Z\", \"updated_at\": \"2026-05-14T10:39:15.654Z\", \"conclusion\": \"failed\"}, \"sft-dryrun-73\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:19:34.694Z\", \"updated_at\": \"2026-05-14T08:20:00.752Z\", \"spec\": {\"command\": \"swift sft --config configs/sft_vanilla.yaml (dry-run, 1 epoch, bs=1, max_length=2048)\", \"server\": \"autodl-5090\", \"data_path\": \"data/trajectories/ (124 successful trajectories)\", \"data_count\": 124, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"gpu\": \"cuda:0\", \"hypothesis\": \"SFT pipeline 端到端验证：注入→格式化→训练流程是否正常工作\", \"checkpoint_path\": \"checkpoints/dryrun_sft_v2/v0-20260514-161410/checkpoint-8/\", \"log_path\": \"checkpoints/dryrun_sft_v2/v0-20260514-161410/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T08:19:52.165Z\", \"metrics\": {\"train_loss_init\": 2.436, \"train_loss_final\": 1.543, \"train_loss_avg\": 1.894, \"peak_memory_gib\": 19.22, \"steps\": 8, \"duration_sec\": 42, \"data_vanilla\": 124, \"data_injected_dryrun\": 96, \"injected_failed\": 4}}}, \"count\": 125, \"total\": 125, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3011}}"
    }
  },
  "sourceToolAssistantUUID": "d80cb16a-2266-46e1-a4ea-1b61c5da5a06",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-15T22:13:17.342Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01NYS1hJxGD35E9owT6HZDs7`</summary>

```json
{
  "project": "tax_error_inject_agent",
  "file": "report.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "80a0179a-2b35-4e41-8db4-ee22550e3dd1",
  "isSidechain": false,
  "requestId": "req_011Cb587UbB2TDpiU77v9SxC",
  "type": "assistant",
  "uuid": "be6eb32b-38a8-4df2-987b-54e06692e8a5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Yeq9e7ndLiLQghfRuotxD",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1136,
      "cache_read_input_tokens": 34836,
      "output_tokens": 242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1136,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 242,
          "cache_read_input_tokens": 34836,
          "cache_creation_input_tokens": 1136,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1136
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

_source line 16 · 2026-05-15T22:13:17.396Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_roadmap · `toolu_01UjNTpNEjshjeUYxKKiFZRD`</summary>

```json
{
  "project": "tax_error_inject_agent"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "be6eb32b-38a8-4df2-987b-54e06692e8a5",
  "isSidechain": false,
  "requestId": "req_011Cb587UbB2TDpiU77v9SxC",
  "type": "assistant",
  "uuid": "0329aa87-10f2-4b60-98a1-a5ef3d9b80ca",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Yeq9e7ndLiLQghfRuotxD",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1136,
      "cache_read_input_tokens": 34836,
      "output_tokens": 242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1136,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 242,
          "cache_read_input_tokens": 34836,
          "cache_creation_input_tokens": 1136,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1136
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

### Runtime record

_source line 17_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[CRON] 实验进程已正常退出，状态已转为 ANALYZING，需要你分析结果并推进到 DONE。 详情: Process exited cleanly, W&B data available  - exp_id: v4-random-fixed-inject10-s7-eval - project: tax_error_inject_agent - server: autodl-5090 -…",
  "leafUuid": "0329aa87-10f2-4b60-98a1-a5ef3d9b80ca",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e"
}
```

---

### Runtime record

_source line 18_

```json
{
  "type": "ai-title",
  "aiTitle": "Analyze experiment results and complete workflow",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e"
}
```

---

### Tool result

_source line 19 · 2026-05-15T22:13:23.497Z_

<details><summary>↩ Tool result · `toolu_01N2Wn4su8dFcGJhxmYpGtTS`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"reconciled\": 4, \"results\": [{\"exp_id\": \"v4-recovery-paired-datagen\", \"success\": true, \"actions\": [\"Job still running (pid=158010)\"]}, {\"exp_id\": \"v4-taxei-fixed-inject25-s1\", \"success\": true, \"actions\": [\"Job still running (pid=199599)\"]}, {\"exp_id\": \"v4-random-fixed-inject25-s1\", \"success\": true, \"actions\": [\"Job still running (pid=200146)\"]}, {\"exp_id\": \"v4-taxei-fixed-inject25-s7\", \"success\": true, \"actions\": [\"Job still running (pid=200226)\"]}]}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4c73c802-3620-40c0-89d3-8493efbfc044",
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "07d782b1-29cd-451f-a48c-a98480249986",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"reconciled\\\": 4, \\\"results\\\": [{\\\"exp_id\\\": \\\"v4-recovery-paired-datagen\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=158010)\\\"]}, {\\\"exp_id\\\": \\\"v4-taxei-fixed-inject25-s1\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=199599)\\\"]}, {\\\"exp_id\\\": \\\"v4-random-fixed-inject25-s1\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=200146)\\\"]}, {\\\"exp_id\\\": \\\"v4-taxei-fixed-inject25-s7\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=200226)\\\"]}]}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"reconciled\": 4, \"results\": [{\"exp_id\": \"v4-recovery-paired-datagen\", \"success\": true, \"actions\": [\"Job still running (pid=158010)\"]}, {\"exp_id\": \"v4-taxei-fixed-inject25-s1\", \"success\": true, \"actions\": [\"Job still running (pid=199599)\"]}, {\"exp_id\": \"v4-random-fixed-inject25-s1\", \"success\": true, \"actions\": [\"Job still running (pid=200146)\"]}, {\"exp_id\": \"v4-taxei-fixed-inject25-s7\", \"success\": true, \"actions\": [\"Job still running (pid=200226)\"]}]}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "4c73c802-3620-40c0-89d3-8493efbfc044",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-15T22:13:23.517Z_

<details><summary>↩ Tool result · `toolu_01NYS1hJxGD35E9owT6HZDs7`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/report.md\", \"content\": \"&lt;!-- AUTO-FACTS-BEGIN (generated 2026-05-15T22:12:59Z; do not edit — regenerated by auto_build_report_facts) -->\\n## 📊 当前状态（auto-derived from registry）\\n\\n**总计**: 125 个实验 — ANALYZING 1, DONE 66, PREPARING 55, RUNNING 3\\n**DONE 分布**: failed 4, negative 5, success 57\\n\\n### GPU 占用\\n- **实际运行**: 3 张 — autodl-5090:cuda:2(v4-taxei-fixed-inject25-s1), autodl-5090:cuda:0(v4-random-fixed-inject25-s1), autodl-5090:cuda:1(v4-taxei-fixed-inject25-s7)\\n\\n### 🏃 RUNNING\\n| exp_id | server | gpu | pid | log |\\n|--------|--------|-----|-----|-----|\\n| `v4-taxei-fixed-inject25-s1` | autodl-5090 | cuda:2 | 199599 | `~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s1.log` |\\n| `v4-random-fixed-inject25-s1` | autodl-5090 | cuda:0 | 200146 | `…runs/tax_error_inject_agent/v4-random-fixed-inject25-s1.log` |\\n| `v4-taxei-fixed-inject25-s7` | autodl-5090 | cuda:1 | 200226 | `~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s7.log` |\\n\\n### 📌 最近完成 (top 5)\\n- `v4-random-fixed-inject10-s7` [success] — 2026-05-15T21:57:11\\n- `v4-random-fixed-inject10-s1-eval` [success] — 2026-05-15T21:27:48\\n- `v4-taxei-fixed-inject10-s7-eval` [success] — 2026-05-15T21:27:44\\n- `v4-taxei-fixed-inject10-s1-eval-r2` [success] — 2026-05-15T21:06:11\\n- `v4-taxei-fixed-inject10-s7` [success] — 2026-05-15T21:05:01\\n\\n&lt;!-- AUTO-FACTS-END -->\\n\\n---\\n\\n# Handover — 2026-05-15\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| v4-taxei-fixed-inject25-s7 | v4 TaxEI fixed-size ablation: 25% injection ratio seed=7 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion. | — | — | — |\\n| v4-random-fixed-inject25-s1 | v4 Random fixed-size ablation: 25% injection ratio seed=1 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion. | — | — | — |\\n| v4-taxei-fixed-inject25-s1 | v4 TaxEI fixed-size ablation: 25% injection ratio seed=1 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion. | — | — | — |\\n\\n## 待处理\\n- v4-random-fixed-inject10-s0-eval-r2: v4 Random 10% seed=0 eval (retry, OOM fix) — 47 ALFWorld clean tasks. Dedicated GPU.（准备中）\\n- v4-taxei-fixed-inject10-s123-eval-r2: v4 TaxEI 10% seed=123 eval (retry, OOM fix) — 47 ALFWorld clean tasks. Dedicated GPU.（准备中）\\n- v4-taxei-inject10-seed0（准备中）\\n- v4-random-inject10-seed0（准备中）\\n- v4-taxei-inject10-seed123（准备中）\\n- qualitative-failure-analysis: D026 Qualitative Failure Analysis: Extract failure patterns from existing eval logs. Key finding: TaxEI loop_repetition rate 17.4% vs Vanilla 7.8% vs Random 3.2%. TaxEI models exhibit fixation behavior (repeated action loops) especially on multi-step tasks under P1/P2 operators.（准备中）\\n- v4-recovery-paired-datagen: Recovery-paired injection data generation: 711 injected variants × GPT API recovery demos. Each injected trajectory gets a paired recovery continuation from the error state. For recovery-paired SFT training.（准备中）\\n- v4-random-recovery-eval-s123（准备中）\\n- v4-random-recovery-eval-s0（准备中）\\n- v4-taxei-recovery-eval-s123（准备中）\\n- …另有 45 项\\n\\n## 近期结论\\n- **v4-random-fixed-inject10-s7** (success): v4 Random fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion — 最后一个 10% 训练。\\n- **v4-random-fixed-inject10-s1-eval** (success): v4 Random 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\n- **v4-taxei-fixed-inject10-s7-eval** (success): v4 TaxEI 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\n\\n## 趋势\\n成功 57 / 负向 5 / 失败 4 / 共 66\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nautodl-5090: 空闲 cuda:0, cuda:1, cuda:2, cuda:3\\n\\n## 告警\\n- v4-taxei-fixed-inject25: 训练失败 — unknown\\n- v4-taxei-fixed-inject10-s123-eval: 训练失败 — unknown\\n- v4-random-fixed-inject10-s0-eval: 训练失败 — unknown\\n- v4-taxei-fixed-inject10-s1-eval: 训练失败 — unknown\\n\", \"total_chars\": 3797, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "be6eb32b-38a8-4df2-987b-54e06692e8a5",
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "4181068a-ce51-445b-9f49-197c5fd02686",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/report.md\\\", \\\"content\\\": \\\"&lt;!-- AUTO-FACTS-BEGIN (generated 2026-05-15T22:12:59Z; do not edit — regenerated by auto_build_report_facts) -->\\\\n## 📊 当前状态（auto-derived from registry）\\\\n\\\\n**总计**: 125 个实验 — ANALYZING 1, DONE 66, PREPARING 55, RUNNING 3\\\\n**DONE 分布**: failed 4, negative 5, success 57\\\\n\\\\n### GPU 占用\\\\n- **实际运行**: 3 张 — autodl-5090:cuda:2(v4-taxei-fixed-inject25-s1), autodl-5090:cuda:0(v4-random-fixed-inject25-s1), autodl-5090:cuda:1(v4-taxei-fixed-inject25-s7)\\\\n\\\\n### 🏃 RUNNING\\\\n| exp_id | server | gpu | pid | log |\\\\n|--------|--------|-----|-----|-----|\\\\n| `v4-taxei-fixed-inject25-s1` | autodl-5090 | cuda:2 | 199599 | `~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s1.log` |\\\\n| `v4-random-fixed-inject25-s1` | autodl-5090 | cuda:0 | 200146 | `…runs/tax_error_inject_agent/v4-random-fixed-inject25-s1.log` |\\\\n| `v4-taxei-fixed-inject25-s7` | autodl-5090 | cuda:1 | 200226 | `~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s7.log` |\\\\n\\\\n### 📌 最近完成 (top 5)\\\\n- `v4-random-fixed-inject10-s7` [success] — 2026-05-15T21:57:11\\\\n- `v4-random-fixed-inject10-s1-eval` [success] — 2026-05-15T21:27:48\\\\n- `v4-taxei-fixed-inject10-s7-eval` [success] — 2026-05-15T21:27:44\\\\n- `v4-taxei-fixed-inject10-s1-eval-r2` [success] — 2026-05-15T21:06:11\\\\n- `v4-taxei-fixed-inject10-s7` [success] — 2026-05-15T21:05:01\\\\n\\\\n&lt;!-- AUTO-FACTS-END -->\\\\n\\\\n---\\\\n\\\\n# Handover — 2026-05-15\\\\n\\\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\\\n\\\\n## 运行中\\\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\\\n|--------|------|------|---------|-----|\\\\n| v4-taxei-fixed-inject25-s7 | v4 TaxEI fixed-size ablation: 25% injection ratio seed=7 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion. | — | — | — |\\\\n| v4-random-fixed-inject25-s1 | v4 Random fixed-size ablation: 25% injection ratio seed=1 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion. | — | — | — |\\\\n| v4-taxei-fixed-inject25-s1 | v4 TaxEI fixed-size ablation: 25% injection ratio seed=1 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion. | — | — | — |\\\\n\\\\n## 待处理\\\\n- v4-random-fixed-inject10-s0-eval-r2: v4 Random 10% seed=0 eval (retry, OOM fix) — 47 ALFWorld clean tasks. Dedicated GPU.（准备中）\\\\n- v4-taxei-fixed-inject10-s123-eval-r2: v4 TaxEI 10% seed=123 eval (retry, OOM fix) — 47 ALFWorld clean tasks. Dedicated GPU.（准备中）\\\\n- v4-taxei-inject10-seed0（准备中）\\\\n- v4-random-inject10-seed0（准备中）\\\\n- v4-taxei-inject10-seed123（准备中）\\\\n- qualitative-failure-analysis: D026 Qualitative Failure Analysis: Extract failure patterns from existing eval logs. Key finding: TaxEI loop_repetition rate 17.4% vs Vanilla 7.8% vs Random 3.2%. TaxEI models exhibit fixation behavior (repeated action loops) especially on multi-step tasks under P1/P2 operators.（准备中）\\\\n- v4-recovery-paired-datagen: Recovery-paired injection data generation: 711 injected variants × GPT API recovery demos. Each injected trajectory gets a paired recovery continuation from the error state. For recovery-paired SFT training.（准备中）\\\\n- v4-random-recovery-eval-s123（准备中）\\\\n- v4-random-recovery-eval-s0（准备中）\\\\n- v4-taxei-recovery-eval-s123（准备中）\\\\n- …另有 45 项\\\\n\\\\n## 近期结论\\\\n- **v4-random-fixed-inject10-s7** (success): v4 Random fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion — 最后一个 10% 训练。\\\\n- **v4-random-fixed-inject10-s1-eval** (success): v4 Random 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\\\n- **v4-taxei-fixed-inject10-s7-eval** (success): v4 TaxEI 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\\\n\\\\n## 趋势\\\\n成功 57 / 负向 5 / 失败 4 / 共 66\\\\n\\\\n## 下一步\\\\n（无活跃 idea，请通过 ideas.md 添加）\\\\n\\\\n## 资源状态\\\\nautodl-5090: 空闲 cuda:0, cuda:1, cuda:2, cuda:3\\\\n\\\\n## 告警\\\\n- v4-taxei-fixed-inject25: 训练失败 — unknown\\\\n- v4-taxei-fixed-inject10-s123-eval: 训练失败 — unknown\\\\n- v4-random-fixed-inject10-s0-eval: 训练失败 — unknown\\\\n- v4-taxei-fixed-inject10-s1-eval: 训练失败 — unknown\\\\n\\\", \\\"total_chars\\\": 3797, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/report.md\", \"content\": \"&lt;!-- AUTO-FACTS-BEGIN (generated 2026-05-15T22:12:59Z; do not edit — regenerated by auto_build_report_facts) -->\\n## 📊 当前状态（auto-derived from registry）\\n\\n**总计**: 125 个实验 — ANALYZING 1, DONE 66, PREPARING 55, RUNNING 3\\n**DONE 分布**: failed 4, negative 5, success 57\\n\\n### GPU 占用\\n- **实际运行**: 3 张 — autodl-5090:cuda:2(v4-taxei-fixed-inject25-s1), autodl-5090:cuda:0(v4-random-fixed-inject25-s1), autodl-5090:cuda:1(v4-taxei-fixed-inject25-s7)\\n\\n### 🏃 RUNNING\\n| exp_id | server | gpu | pid | log |\\n|--------|--------|-----|-----|-----|\\n| `v4-taxei-fixed-inject25-s1` | autodl-5090 | cuda:2 | 199599 | `~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s1.log` |\\n| `v4-random-fixed-inject25-s1` | autodl-5090 | cuda:0 | 200146 | `…runs/tax_error_inject_agent/v4-random-fixed-inject25-s1.log` |\\n| `v4-taxei-fixed-inject25-s7` | autodl-5090 | cuda:1 | 200226 | `~/runs/tax_error_inject_agent/v4-taxei-fixed-inject25-s7.log` |\\n\\n### 📌 最近完成 (top 5)\\n- `v4-random-fixed-inject10-s7` [success] — 2026-05-15T21:57:11\\n- `v4-random-fixed-inject10-s1-eval` [success] — 2026-05-15T21:27:48\\n- `v4-taxei-fixed-inject10-s7-eval` [success] — 2026-05-15T21:27:44\\n- `v4-taxei-fixed-inject10-s1-eval-r2` [success] — 2026-05-15T21:06:11\\n- `v4-taxei-fixed-inject10-s7` [success] — 2026-05-15T21:05:01\\n\\n&lt;!-- AUTO-FACTS-END -->\\n\\n---\\n\\n# Handover — 2026-05-15\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| v4-taxei-fixed-inject25-s7 | v4 TaxEI fixed-size ablation: 25% injection ratio seed=7 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion. | — | — | — |\\n| v4-random-fixed-inject25-s1 | v4 Random fixed-size ablation: 25% injection ratio seed=1 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion. | — | — | — |\\n| v4-taxei-fixed-inject25-s1 | v4 TaxEI fixed-size ablation: 25% injection ratio seed=1 (4,358 total = 3,269 clean + 1,089 injected). Dose-response 5-seed expansion. | — | — | — |\\n\\n## 待处理\\n- v4-random-fixed-inject10-s0-eval-r2: v4 Random 10% seed=0 eval (retry, OOM fix) — 47 ALFWorld clean tasks. Dedicated GPU.（准备中）\\n- v4-taxei-fixed-inject10-s123-eval-r2: v4 TaxEI 10% seed=123 eval (retry, OOM fix) — 47 ALFWorld clean tasks. Dedicated GPU.（准备中）\\n- v4-taxei-inject10-seed0（准备中）\\n- v4-random-inject10-seed0（准备中）\\n- v4-taxei-inject10-seed123（准备中）\\n- qualitative-failure-analysis: D026 Qualitative Failure Analysis: Extract failure patterns from existing eval logs. Key finding: TaxEI loop_repetition rate 17.4% vs Vanilla 7.8% vs Random 3.2%. TaxEI models exhibit fixation behavior (repeated action loops) especially on multi-step tasks under P1/P2 operators.（准备中）\\n- v4-recovery-paired-datagen: Recovery-paired injection data generation: 711 injected variants × GPT API recovery demos. Each injected trajectory gets a paired recovery continuation from the error state. For recovery-paired SFT training.（准备中）\\n- v4-random-recovery-eval-s123（准备中）\\n- v4-random-recovery-eval-s0（准备中）\\n- v4-taxei-recovery-eval-s123（准备中）\\n- …另有 45 项\\n\\n## 近期结论\\n- **v4-random-fixed-inject10-s7** (success): v4 Random fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion — 最后一个 10% 训练。\\n- **v4-random-fixed-inject10-s1-eval** (success): v4 Random 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\n- **v4-taxei-fixed-inject10-s7-eval** (success): v4 TaxEI 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\n\\n## 趋势\\n成功 57 / 负向 5 / 失败 4 / 共 66\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nautodl-5090: 空闲 cuda:0, cuda:1, cuda:2, cuda:3\\n\\n## 告警\\n- v4-taxei-fixed-inject25: 训练失败 — unknown\\n- v4-taxei-fixed-inject10-s123-eval: 训练失败 — unknown\\n- v4-random-fixed-inject10-s0-eval: 训练失败 — unknown\\n- v4-taxei-fixed-inject10-s1-eval: 训练失败 — unknown\\n\", \"total_chars\": 3797, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "be6eb32b-38a8-4df2-987b-54e06692e8a5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-15T22:13:23.541Z_

<details><summary>↩ Tool result · `toolu_01UjNTpNEjshjeUYxKKiFZRD`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/ROADMAP.md\", \"content\": \"# tax_error_inject_agent — Research Dashboard\\n\\n> 最后更新: 2026-05-15 18:36 UTC | 更新原因: Wave 1 完成状态同步 + dose-response 5-seed 进展更新\\n\\n## 核心方向\\nTaxonomy-guided error injection 从 tool-use 迁移到 embodied planning 的边界条件研究（negative result paper）。详见 paper_framing.md。\\n\\n## 当前阶段\\n**Long Paper 扩展** (D025) — 8 页 EMNLP 2026 Findings 长文。Wave 1 基本完成，正在执行 dose-response 5-seed 扩展。\\n\\n## 投稿目标\\nEMNLP 2026 Findings (Budapest, Oct 22-29), 8-page long paper\\n\\n## 核心数据 (5-seed)\\n| Condition | Mean±SD | Seeds (42/0/123/1/7) |\\n|-----------|---------|----------------------|\\n| Vanilla | 67.3±4.7 | 61.7/68.1/66.0/72.3/68.1 |\\n| TaxEI full | 58.3±6.5 | 61.7/46.8/61.7/63.8/57.4 |\\n| Random full | 58.3±8.7 | 66.0/55.3/68.1/46.8/55.3 |\\n\\n**核心发现**: TaxEI = Random = 58.3% = 137/235，taxonomy 标签零收益。\\n\\n## 已完成 (Wave 1)\\n- [x] 5-seed 主实验: Vanilla 67.3±4.7, TaxEI 58.3±6.5, Random 58.3±8.7 (D032)\\n- [x] Training dynamics: 训练 loss 跨 seed 极稳定(SD=0.0004)，memorization-generalization dissociation (D027/D029)\\n- [x] Qualitative failure analysis: TaxEI loop_repetition 2.2× (17.4% vs 7.8%) (D026)\\n- [x] Extended stats: bootstrap CI [+3.4,+15.8], power 45.2%, BF=0.68 (D030-D032)\\n- [x] Dose-response 3-seed (25%/50%): dual regime confirmed\\n- [x] Recovery eval seed=42: TaxEI 59.6%, detection 0%\\n\\n## 进行中\\n- [ ] Dose-response 10% 5-seed: TaxEI s0 done, s123/s1 training, s7 pending; Random s0/s123 training, s1/s7 pending\\n- [ ] Recovery-paired datagen: GPT-5.2 生成中 (PID 158010, ~$15 API cost)\\n- [ ] Forward pass v2 结果待审阅\\n\\n## 待执行 (Wave 2)\\n- [ ] Dose-response 25%/50% seeds 1,7 (TaxEI + Random)\\n- [ ] Recovery-paired injection: 训练 TaxEI-RP 3-5 seeds + eval (~16 GPU-h)\\n- [ ] Recovery eval multi-seed: 5 seeds × 3 conditions (~15 GPU-h)\\n\\n## 待执行 (Wave 3)\\n- [ ] WebShop replication: 全 pipeline (~30 GPU-h)\\n\\n## GPU 预算\\n4 × RTX 5090 (autodl-5090), 全部占用中。估算剩余 ~80 GPU-h。\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 | 关联实验 |\\n|----|------|------|----------|\\n| D033 | 2026-05-15 | Forward pass v2 修正: dose-response 非单调, Random 记忆深度 | v4-training-dynamics-forward-v2, v4-training-dynamics-forward |\\n| D032 | 2026-05-15 | 5-seed 完整统计：TaxEI=Random=58.3% 均值完全一致，taxonomy 标签零 | multiseed-vanilla, multiseed-taxei, multiseed-random |\\n| D031 | 2026-05-15 | Random seed1=46.8% 灾难性 outlier 改变 variance gradien | multiseed-random |\\n| D030 | 2026-05-15 | 5-seed Vanilla-TaxEI 差异达 p=0.039 (uncorrected)，Bon | multiseed-taxei |\\n| D029 | 2026-05-15 | Forward pass 揭示注入样本被深度记忆(injected loss < clean los | v4-training-dynamics-forward |\\n| D028 | 2026-05-15 | 批准 Claim 3 从 \\\"training instability\\\" 改为 \\\"generaliza | training-dynamics, qualitative-failure-analysis |\\n| D027 | 2026-05-15 | Training dynamics: 训练 loss 跨 seed 极稳定(SD=0.0004)但  | training-dynamics |\\n| D026 | 2026-05-15 | Qualitative failure analysis 发现 TaxEI loop_repetit | qualitative-failure-analysis |\\n| D025 | 2026-05-15 | 用户指令: 从 workshop 短文 (4p) 转为长文 (8p)，不再考虑 short pape | — |\\n| D024 | 2026-05-15 | Round 2 审稿 Action Matrix: 3 MF (checklist framing降 | — |\\n\\n\", \"lines\": 62}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0329aa87-10f2-4b60-98a1-a5ef3d9b80ca",
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "3ef07c55-8edc-46f4-a2e8-4e228a6d25ab",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/ROADMAP.md\\\", \\\"content\\\": \\\"# tax_error_inject_agent — Research Dashboard\\\\n\\\\n> 最后更新: 2026-05-15 18:36 UTC | 更新原因: Wave 1 完成状态同步 + dose-response 5-seed 进展更新\\\\n\\\\n## 核心方向\\\\nTaxonomy-guided error injection 从 tool-use 迁移到 embodied planning 的边界条件研究（negative result paper）。详见 paper_framing.md。\\\\n\\\\n## 当前阶段\\\\n**Long Paper 扩展** (D025) — 8 页 EMNLP 2026 Findings 长文。Wave 1 基本完成，正在执行 dose-response 5-seed 扩展。\\\\n\\\\n## 投稿目标\\\\nEMNLP 2026 Findings (Budapest, Oct 22-29), 8-page long paper\\\\n\\\\n## 核心数据 (5-seed)\\\\n| Condition | Mean±SD | Seeds (42/0/123/1/7) |\\\\n|-----------|---------|----------------------|\\\\n| Vanilla | 67.3±4.7 | 61.7/68.1/66.0/72.3/68.1 |\\\\n| TaxEI full | 58.3±6.5 | 61.7/46.8/61.7/63.8/57.4 |\\\\n| Random full | 58.3±8.7 | 66.0/55.3/68.1/46.8/55.3 |\\\\n\\\\n**核心发现**: TaxEI = Random = 58.3% = 137/235，taxonomy 标签零收益。\\\\n\\\\n## 已完成 (Wave 1)\\\\n- [x] 5-seed 主实验: Vanilla 67.3±4.7, TaxEI 58.3±6.5, Random 58.3±8.7 (D032)\\\\n- [x] Training dynamics: 训练 loss 跨 seed 极稳定(SD=0.0004)，memorization-generalization dissociation (D027/D029)\\\\n- [x] Qualitative failure analysis: TaxEI loop_repetition 2.2× (17.4% vs 7.8%) (D026)\\\\n- [x] Extended stats: bootstrap CI [+3.4,+15.8], power 45.2%, BF=0.68 (D030-D032)\\\\n- [x] Dose-response 3-seed (25%/50%): dual regime confirmed\\\\n- [x] Recovery eval seed=42: TaxEI 59.6%, detection 0%\\\\n\\\\n## 进行中\\\\n- [ ] Dose-response 10% 5-seed: TaxEI s0 done, s123/s1 training, s7 pending; Random s0/s123 training, s1/s7 pending\\\\n- [ ] Recovery-paired datagen: GPT-5.2 生成中 (PID 158010, ~$15 API cost)\\\\n- [ ] Forward pass v2 结果待审阅\\\\n\\\\n## 待执行 (Wave 2)\\\\n- [ ] Dose-response 25%/50% seeds 1,7 (TaxEI + Random)\\\\n- [ ] Recovery-paired injection: 训练 TaxEI-RP 3-5 seeds + eval (~16 GPU-h)\\\\n- [ ] Recovery eval multi-seed: 5 seeds × 3 conditions (~15 GPU-h)\\\\n\\\\n## 待执行 (Wave 3)\\\\n- [ ] WebShop replication: 全 pipeline (~30 GPU-h)\\\\n\\\\n## GPU 预算\\\\n4 × RTX 5090 (autodl-5090), 全部占用中。估算剩余 ~80 GPU-h。\\\\n\\\\n## 关键决策日志\\\\n\\\\n| ID | 日期 | 摘要 | 关联实验 |\\\\n|----|------|------|----------|\\\\n| D033 | 2026-05-15 | Forward pass v2 修正: dose-response 非单调, Random 记忆深度 | v4-training-dynamics-forward-v2, v4-training-dynamics-forward |\\\\n| D032 | 2026-05-15 | 5-seed 完整统计：TaxEI=Random=58.3% 均值完全一致，taxonomy 标签零 | multiseed-vanilla, multiseed-taxei, multiseed-random |\\\\n| D031 | 2026-05-15 | Random seed1=46.8% 灾难性 outlier 改变 variance gradien | multiseed-random |\\\\n| D030 | 2026-05-15 | 5-seed Vanilla-TaxEI 差异达 p=0.039 (uncorrected)，Bon | multiseed-taxei |\\\\n| D029 | 2026-05-15 | Forward pass 揭示注入样本被深度记忆(injected loss < clean los | v4-training-dynamics-forward |\\\\n| D028 | 2026-05-15 | 批准 Claim 3 从 \\\\\\\"training instability\\\\\\\" 改为 \\\\\\\"generaliza | training-dynamics, qualitative-failure-analysis |\\\\n| D027 | 2026-05-15 | Training dynamics: 训练 loss 跨 seed 极稳定(SD=0.0004)但  | training-dynamics |\\\\n| D026 | 2026-05-15 | Qualitative failure analysis 发现 TaxEI loop_repetit | qualitative-failure-analysis |\\\\n| D025 | 2026-05-15 | 用户指令: 从 workshop 短文 (4p) 转为长文 (8p)，不再考虑 short pape | — |\\\\n| D024 | 2026-05-15 | Round 2 审稿 Action Matrix: 3 MF (checklist framing降 | — |\\\\n\\\\n\\\", \\\"lines\\\": 62}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/ROADMAP.md\", \"content\": \"# tax_error_inject_agent — Research Dashboard\\n\\n> 最后更新: 2026-05-15 18:36 UTC | 更新原因: Wave 1 完成状态同步 + dose-response 5-seed 进展更新\\n\\n## 核心方向\\nTaxonomy-guided error injection 从 tool-use 迁移到 embodied planning 的边界条件研究（negative result paper）。详见 paper_framing.md。\\n\\n## 当前阶段\\n**Long Paper 扩展** (D025) — 8 页 EMNLP 2026 Findings 长文。Wave 1 基本完成，正在执行 dose-response 5-seed 扩展。\\n\\n## 投稿目标\\nEMNLP 2026 Findings (Budapest, Oct 22-29), 8-page long paper\\n\\n## 核心数据 (5-seed)\\n| Condition | Mean±SD | Seeds (42/0/123/1/7) |\\n|-----------|---------|----------------------|\\n| Vanilla | 67.3±4.7 | 61.7/68.1/66.0/72.3/68.1 |\\n| TaxEI full | 58.3±6.5 | 61.7/46.8/61.7/63.8/57.4 |\\n| Random full | 58.3±8.7 | 66.0/55.3/68.1/46.8/55.3 |\\n\\n**核心发现**: TaxEI = Random = 58.3% = 137/235，taxonomy 标签零收益。\\n\\n## 已完成 (Wave 1)\\n- [x] 5-seed 主实验: Vanilla 67.3±4.7, TaxEI 58.3±6.5, Random 58.3±8.7 (D032)\\n- [x] Training dynamics: 训练 loss 跨 seed 极稳定(SD=0.0004)，memorization-generalization dissociation (D027/D029)\\n- [x] Qualitative failure analysis: TaxEI loop_repetition 2.2× (17.4% vs 7.8%) (D026)\\n- [x] Extended stats: bootstrap CI [+3.4,+15.8], power 45.2%, BF=0.68 (D030-D032)\\n- [x] Dose-response 3-seed (25%/50%): dual regime confirmed\\n- [x] Recovery eval seed=42: TaxEI 59.6%, detection 0%\\n\\n## 进行中\\n- [ ] Dose-response 10% 5-seed: TaxEI s0 done, s123/s1 training, s7 pending; Random s0/s123 training, s1/s7 pending\\n- [ ] Recovery-paired datagen: GPT-5.2 生成中 (PID 158010, ~$15 API cost)\\n- [ ] Forward pass v2 结果待审阅\\n\\n## 待执行 (Wave 2)\\n- [ ] Dose-response 25%/50% seeds 1,7 (TaxEI + Random)\\n- [ ] Recovery-paired injection: 训练 TaxEI-RP 3-5 seeds + eval (~16 GPU-h)\\n- [ ] Recovery eval multi-seed: 5 seeds × 3 conditions (~15 GPU-h)\\n\\n## 待执行 (Wave 3)\\n- [ ] WebShop replication: 全 pipeline (~30 GPU-h)\\n\\n## GPU 预算\\n4 × RTX 5090 (autodl-5090), 全部占用中。估算剩余 ~80 GPU-h。\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 | 关联实验 |\\n|----|------|------|----------|\\n| D033 | 2026-05-15 | Forward pass v2 修正: dose-response 非单调, Random 记忆深度 | v4-training-dynamics-forward-v2, v4-training-dynamics-forward |\\n| D032 | 2026-05-15 | 5-seed 完整统计：TaxEI=Random=58.3% 均值完全一致，taxonomy 标签零 | multiseed-vanilla, multiseed-taxei, multiseed-random |\\n| D031 | 2026-05-15 | Random seed1=46.8% 灾难性 outlier 改变 variance gradien | multiseed-random |\\n| D030 | 2026-05-15 | 5-seed Vanilla-TaxEI 差异达 p=0.039 (uncorrected)，Bon | multiseed-taxei |\\n| D029 | 2026-05-15 | Forward pass 揭示注入样本被深度记忆(injected loss < clean los | v4-training-dynamics-forward |\\n| D028 | 2026-05-15 | 批准 Claim 3 从 \\\"training instability\\\" 改为 \\\"generaliza | training-dynamics, qualitative-failure-analysis |\\n| D027 | 2026-05-15 | Training dynamics: 训练 loss 跨 seed 极稳定(SD=0.0004)但  | training-dynamics |\\n| D026 | 2026-05-15 | Qualitative failure analysis 发现 TaxEI loop_repetit | qualitative-failure-analysis |\\n| D025 | 2026-05-15 | 用户指令: 从 workshop 短文 (4p) 转为长文 (8p)，不再考虑 short pape | — |\\n| D024 | 2026-05-15 | Round 2 审稿 Action Matrix: 3 MF (checklist framing降 | — |\\n\\n\", \"lines\": 62}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "0329aa87-10f2-4b60-98a1-a5ef3d9b80ca",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 22 · 2026-05-15T22:13:30.064Z_

<details><summary>Logged reasoning block</summary>

```text
Let me understand the situation:

1. Experiment `v4-random-fixed-inject10-s7-eval` just completed (ANALYZING state), needs analysis
2. There are 3 running experiments: v4-taxei-fixed-inject25-s1, v4-random-fixed-inject25-s1, v4-taxei-fixed-inject25-s7
3. Plus v4-recovery-paired-datagen is running

Now I need to:
1. Read the registry entry for `v4-random-fixed-inject10-s7-eval` specifically


2. Analyze the results by pulling the log data and W&B metrics for this experiment

Let me fetch the specific experiment details from the registry and check what metrics are available on W&B.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3ef07c55-8edc-46f4-a2e8-4e228a6d25ab",
  "isSidechain": false,
  "requestId": "req_011Cb588G29ps6YeETJpXBkf",
  "type": "assistant",
  "uuid": "fc8f614b-bbca-44c8-b6dd-8e60914df1c6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PkoYisjska4Gbu6yGgiVWS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4548,
      "cache_read_input_tokens": 35972,
      "output_tokens": 461,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4548,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 461,
          "cache_read_input_tokens": 35972,
          "cache_creation_input_tokens": 4548,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4548
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

_source line 23 · 2026-05-15T22:13:30.171Z_

需要查看完成实验的详细信息和 W&B 指标。先读 registry 中该实验的条目。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fc8f614b-bbca-44c8-b6dd-8e60914df1c6",
  "isSidechain": false,
  "requestId": "req_011Cb588G29ps6YeETJpXBkf",
  "type": "assistant",
  "uuid": "a107c991-0ea2-403e-adf7-afd40a0304c1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PkoYisjska4Gbu6yGgiVWS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4548,
      "cache_read_input_tokens": 35972,
      "output_tokens": 461,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4548,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 461,
          "cache_read_input_tokens": 35972,
          "cache_creation_input_tokens": 4548,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4548
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

_source line 24 · 2026-05-15T22:13:31.188Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_014QBjrZ1o2xh1B5e6BX13Xs`</summary>

```json
{
  "project": "tax_error_inject_agent",
  "filters": {
    "exp_id": "v4-random-fixed-inject10-s7-eval"
  },
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
  "parentUuid": "a107c991-0ea2-403e-adf7-afd40a0304c1",
  "isSidechain": false,
  "requestId": "req_011Cb588G29ps6YeETJpXBkf",
  "type": "assistant",
  "uuid": "0edc5dd1-06af-4e42-a1d2-fce17f3e500e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PkoYisjska4Gbu6yGgiVWS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4548,
      "cache_read_input_tokens": 35972,
      "output_tokens": 461,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4548,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 461,
          "cache_read_input_tokens": 35972,
          "cache_creation_input_tokens": 4548,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4548
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

_source line 25 · 2026-05-15T22:13:31.564Z_

<details><summary>↩ Tool result · `toolu_014QBjrZ1o2xh1B5e6BX13Xs`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3572}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0edc5dd1-06af-4e42-a1d2-fce17f3e500e",
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "f462f635-c474-4daa-ac34-34f08e5246d4",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.3572}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3572}}"
    }
  },
  "sourceToolAssistantUUID": "0edc5dd1-06af-4e42-a1d2-fce17f3e500e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-15T22:13:31.652Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01WLt1k2KCcfkyfnoG8jNRY8`</summary>

```json
{
  "project": "tax_error_inject_agent",
  "filters": {
    "status": "ANALYZING"
  },
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
  "parentUuid": "f462f635-c474-4daa-ac34-34f08e5246d4",
  "isSidechain": false,
  "requestId": "req_011Cb588G29ps6YeETJpXBkf",
  "type": "assistant",
  "uuid": "e15da3a9-7a70-4205-9c78-ad9e05cdbbbe",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PkoYisjska4Gbu6yGgiVWS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4548,
      "cache_read_input_tokens": 35972,
      "output_tokens": 461,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 4548,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 461,
          "cache_read_input_tokens": 35972,
          "cache_creation_input_tokens": 4548,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 4548
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

### Runtime record

_source line 27_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[CRON] 实验进程已正常退出，状态已转为 ANALYZING，需要你分析结果并推进到 DONE。 详情: Process exited cleanly, W&B data available  - exp_id: v4-random-fixed-inject10-s7-eval - project: tax_error_inject_agent - server: autodl-5090 -…",
  "leafUuid": "e15da3a9-7a70-4205-9c78-ad9e05cdbbbe",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e"
}
```

---

### Runtime record

_source line 28_

```json
{
  "type": "ai-title",
  "aiTitle": "Analyze experiment results and complete workflow",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e"
}
```

---

### Tool result

_source line 29 · 2026-05-15T22:13:31.963Z_

<details><summary>↩ Tool result · `toolu_01WLt1k2KCcfkyfnoG8jNRY8`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"v4-random-fixed-inject10-s7-eval\": {\"status\": \"ANALYZING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:57:41.705Z\", \"updated_at\": \"2026-05-15T22:12:58.041Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s7/v1-20260516-045440/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"202328\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s7-eval.log\", \"submitted_at\": \"2026-05-15T21:57:41.444Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s7)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s7\", \"eval_data\": \"eval_tasks_47.json\"}, \"hypothesis\": \"v4 Random 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion. 最后一个 10% eval。\", \"reproduce\": {\"finished_at\": \"2026-05-15T22:12:57.609Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:12:59.982752+00:00\"}]}}}, \"count\": 1, \"total\": 1, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.2779}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e15da3a9-7a70-4205-9c78-ad9e05cdbbbe",
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "7b45a8e1-df77-4b78-9dd6-635644883400",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"v4-random-fixed-inject10-s7-eval\\\": {\\\"status\\\": \\\"ANALYZING\\\", \\\"retry_count\\\": 0, \\\"created_at\\\": \\\"2026-05-15T21:57:41.705Z\\\", \\\"updated_at\\\": \\\"2026-05-15T22:12:58.041Z\\\", \\\"spec\\\": {\\\"command\\\": \\\"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s7/v1-20260516-045440/checkpoint-1635 --num_episodes 47 --seed 42\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"202328\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s7-eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T21:57:41.444Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (random fixed inject10 s7)\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"v4-random-fixed-inject10-s7\\\", \\\"eval_data\\\": \\\"eval_tasks_47.json\\\"}, \\\"hypothesis\\\": \\\"v4 Random 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion. 最后一个 10% eval。\\\", \\\"reproduce\\\": {\\\"finished_at\\\": \\\"2026-05-15T22:12:57.609Z\\\"}, \\\"extra\\\": {\\\"hook_events\\\": [{\\\"event\\\": \\\"on_complete\\\", \\\"action\\\": \\\"agent\\\", \\\"ts\\\": \\\"2026-05-15T22:12:59.982752+00:00\\\"}]}}}, \\\"count\\\": 1, \\\"total\\\": 1, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.2779}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"v4-random-fixed-inject10-s7-eval\": {\"status\": \"ANALYZING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:57:41.705Z\", \"updated_at\": \"2026-05-15T22:12:58.041Z\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s7/v1-20260516-045440/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"202328\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s7-eval.log\", \"submitted_at\": \"2026-05-15T21:57:41.444Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s7)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s7\", \"eval_data\": \"eval_tasks_47.json\"}, \"hypothesis\": \"v4 Random 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion. 最后一个 10% eval。\", \"reproduce\": {\"finished_at\": \"2026-05-15T22:12:57.609Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:12:59.982752+00:00\"}]}}}, \"count\": 1, \"total\": 1, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.2779}}"
    }
  },
  "sourceToolAssistantUUID": "e15da3a9-7a70-4205-9c78-ad9e05cdbbbe",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 30 · 2026-05-15T22:13:39.104Z_

<details><summary>Logged reasoning block</summary>

```text
The experiment `v4-random-fixed-inject10-s7-eval` is in ANALYZING state. It's an eval experiment for Random 10% seed=7 on 47 ALFWorld clean tasks. I need to:

1. Spawn a Worker to analyze the results from W&B and/or logs
2. Update registry with conclusion and metrics
3. Update report.md
4. Report to Director

Let me spawn a worker to analyze the results. The worker should:
- Check W&B metrics for this eval run
- Read the log file for results


- Extract the success rate and other metrics

I should also look at the registry to see what other 10% eval experiments have already completed, so I can compare this run's performance against the baseline.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7b45a8e1-df77-4b78-9dd6-635644883400",
  "isSidechain": false,
  "requestId": "req_011Cb588t45xhbqSKgvTs3oZ",
  "type": "assistant",
  "uuid": "406e2629-1bc3-4a4f-ae1c-2aa62db2ddd7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FnyNjEMPiKVyKUiCS69DrN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1178,
      "cache_read_input_tokens": 40520,
      "output_tokens": 350,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1178,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 350,
          "cache_read_input_tokens": 40520,
          "cache_creation_input_tokens": 1178,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1178
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

_source line 31 · 2026-05-15T22:13:39.110Z_

实验在 ANALYZING 状态，需要分析。先查看已完成的同系列 eval 实验做对比基准。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "406e2629-1bc3-4a4f-ae1c-2aa62db2ddd7",
  "isSidechain": false,
  "requestId": "req_011Cb588t45xhbqSKgvTs3oZ",
  "type": "assistant",
  "uuid": "b327fb80-ceba-4656-9853-ce09a2045b61",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FnyNjEMPiKVyKUiCS69DrN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1178,
      "cache_read_input_tokens": 40520,
      "output_tokens": 350,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1178,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 350,
          "cache_read_input_tokens": 40520,
          "cache_creation_input_tokens": 1178,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1178
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

_source line 32 · 2026-05-15T22:13:39.764Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01TLrnSeZYiSSYL1vnJ4LfnB`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__spawn_worker,mcp__agent-ml-research__update_registry,mcp__agent-ml-research__fetch_wandb_metrics,mcp__agent-ml-research__list_workers",
  "max_results": 4
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b327fb80-ceba-4656-9853-ce09a2045b61",
  "isSidechain": false,
  "requestId": "req_011Cb588t45xhbqSKgvTs3oZ",
  "type": "assistant",
  "uuid": "d116bdc2-39dc-4904-a1f4-f17f3f6c641e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FnyNjEMPiKVyKUiCS69DrN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1178,
      "cache_read_input_tokens": 40520,
      "output_tokens": 350,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1178,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 350,
          "cache_read_input_tokens": 40520,
          "cache_creation_input_tokens": 1178,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1178
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

_source line 33 · 2026-05-15T22:13:39.768Z_

<details><summary>↩ Tool result · `toolu_01TLrnSeZYiSSYL1vnJ4LfnB`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__spawn_worker"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__update_registry"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__fetch_wandb_metrics"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__list_workers"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d116bdc2-39dc-4904-a1f4-f17f3f6c641e",
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "e4f9a8fe-9240-49c5-b467-88d6954b7b50",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__spawn_worker",
      "mcp__agent-ml-research__update_registry",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__list_workers"
    ],
    "query": "select:mcp__agent-ml-research__spawn_worker,mcp__agent-ml-research__update_registry,mcp__agent-ml-research__fetch_wandb_metrics,mcp__agent-ml-research__list_workers",
    "total_deferred_tools": 79
  },
  "sourceToolAssistantUUID": "d116bdc2-39dc-4904-a1f4-f17f3f6c641e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 34 · 2026-05-15T22:13:39.825Z_

```json
{
  "parentUuid": "e4f9a8fe-9240-49c5-b467-88d6954b7b50",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "15607dfb-5531-4706-88ee-b0f8148c8ef2",
  "timestamp": "2026-05-15T22:13:39.825Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 35 · 2026-05-15T22:13:43.413Z_

<details><summary>Logged reasoning block</summary>

```text
Let me spawn a worker to analyze the eval results from the logs and W&B. I need to get the metrics for this experiment. Let me also check what the other 10% eval results look like so I can provide context.

Let me first read the registry for related eval experiments to build comparison context.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "15607dfb-5531-4706-88ee-b0f8148c8ef2",
  "isSidechain": false,
  "requestId": "req_011Cb589TcCAVgDV9UnQhv3Y",
  "type": "assistant",
  "uuid": "43249a8e-e20f-42e8-be36-73838d9372eb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XXqsNUUDeqG6Dg8debGCeB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2549,
      "cache_read_input_tokens": 41698,
      "output_tokens": 340,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2549,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 340,
          "cache_read_input_tokens": 41698,
          "cache_creation_input_tokens": 2549,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2549
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

_source line 36 · 2026-05-15T22:13:45.022Z_

派 Worker 分析实验结果——需要 SSH 读日志 + W&B 拉指标。同时读取已完成的同系列 eval 实验做对比。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "43249a8e-e20f-42e8-be36-73838d9372eb",
  "isSidechain": false,
  "requestId": "req_011Cb589TcCAVgDV9UnQhv3Y",
  "type": "assistant",
  "uuid": "cd4f716e-28a0-4c2f-af34-6fab2f624897",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XXqsNUUDeqG6Dg8debGCeB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2549,
      "cache_read_input_tokens": 41698,
      "output_tokens": 340,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2549,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 340,
          "cache_read_input_tokens": 41698,
          "cache_creation_input_tokens": 2549,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2549
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

_source line 37 · 2026-05-15T22:13:46.011Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01WboaLQsgzmJoqdsDDqseUp`</summary>

```json
{
  "project": "tax_error_inject_agent",
  "filters": {
    "status": "DONE"
  },
  "fields": [
    "exp_id",
    "conclusion",
    "metrics",
    "hypothesis",
    "spec"
  ],
  "limit": 30
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cd4f716e-28a0-4c2f-af34-6fab2f624897",
  "isSidechain": false,
  "requestId": "req_011Cb589TcCAVgDV9UnQhv3Y",
  "type": "assistant",
  "uuid": "b4dedea6-c2e8-4788-a3d2-994037e3272a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XXqsNUUDeqG6Dg8debGCeB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2549,
      "cache_read_input_tokens": 41698,
      "output_tokens": 340,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2549,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 340,
          "cache_read_input_tokens": 41698,
          "cache_creation_input_tokens": 2549,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2549
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

_source line 38 · 2026-05-15T22:13:46.295Z_

<details><summary>↩ Tool result · `toolu_01WboaLQsgzmJoqdsDDqseUp`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"v4-random-fixed-inject10-s7\": {\"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion — 最后一个 10% 训练。\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s7)\", \"seed\": 7}, \"metrics\": {\"final_loss\": 0.2352, \"train_loss_avg\": 0.4209, \"final_token_acc\": 0.9066, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3511.93, \"memory_gib\": 18.15, \"train_speed_s_per_it\": 2.148}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject10-s1-eval\": {\"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"198045\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s1-eval.log\", \"submitted_at\": \"2026-05-15T21:05:18.393Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s1)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635\", \"wall_clock_seconds\": 1350.0, \"gpu_hours\": 0.37}, \"hypothesis\": \"v4 Random 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"metrics\": {\"success_rate\": 0.681, \"successes\": 32, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 10, \"success\": 5, \"rate\": 0.5}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 6, \"rate\": 0.857}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-s7-eval\": {\"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject10_s7/v1-20260516-040128/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"197555\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s7-eval.log\", \"submitted_at\": \"2026-05-15T21:02:21.785Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s7)\", \"seed\": 42, \"checkpoint_source\": \"v4-taxei-fixed-inject10-s7\", \"eval_data\": \"eval_tasks_47.json\", \"wall_clock_seconds\": 1522.4, \"gpu_hours\": 0.42}, \"hypothesis\": \"v4 TaxEI 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"metrics\": {\"success_rate\": 0.681, \"successes\": 32, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-s1-eval-r2\": {\"spec\": {\"parent\": \"v4-taxei-fixed-inject10-s1\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s1)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\"}, \"hypothesis\": \"v4 TaxEI 10% seed=1 eval (r2, dedicated GPU) — 47 ALFWorld clean tasks.\", \"metrics\": {\"success_rate\": 0.511, \"successes\": 24, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 4, \"rate\": 0.667}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-s7\": {\"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion.\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4_fixed_inject10.jsonl --seed 7\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"191997\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s7.log\", \"submitted_at\": \"2026-05-15T20:01:19.314Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"wall_clock_seconds\": 3683.3, \"gpu_hours\": 1.02}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.237, \"train_loss_avg\": 0.4212, \"final_token_acc\": 0.905, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3437, \"memory_gib\": 18.15, \"train_speed_s_per_it\": 2.102}}, \"v4-random-fixed-inject10-s1\": {\"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion.\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_random_v4_fixed_inject10.jsonl --seed 1\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"192077\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s1.log\", \"submitted_at\": \"2026-05-15T20:01:21.468Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"wall_clock_seconds\": 3782.3, \"gpu_hours\": 1.05}, \"metrics\": {\"final_loss\": 0.3096, \"train_loss_avg\": 0.4238, \"final_token_acc\": 0.8902, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3488, \"memory_gib\": 18.13, \"train_speed_s_per_it\": 2.132}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-s123-eval-r3\": {\"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"194978\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123-eval-r3.log\", \"submitted_at\": \"2026-05-15T20:40:05.519Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s123\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s123\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s123)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\", \"wall_clock_seconds\": 848.9, \"gpu_hours\": 0.24}, \"hypothesis\": \"v4 TaxEI 10% seed=123 eval (r3, dedicated GPU) — 47 ALFWorld clean tasks.\", \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject10-s0-eval-r3\": {\"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"195118\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0-eval-r3.log\", \"submitted_at\": \"2026-05-15T20:40:07.156Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10-s0\", \"checkpoint_source\": \"v4-random-fixed-inject10-s0\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s0)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\", \"wall_clock_seconds\": 745.0, \"gpu_hours\": 0.21}, \"hypothesis\": \"v4 Random 10% seed=0 eval (r3, dedicated GPU) — 47 ALFWorld clean tasks.\", \"metrics\": {\"success_rate\": 0.66, \"successes\": 31, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"success\": 7, \"total\": 11, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 7, \"total\": 8, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject10-s0-eval\": {\"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"188022\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0-eval.log\", \"submitted_at\": \"2026-05-15T18:57:43.056Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10-s0\", \"checkpoint_source\": \"v4-random-fixed-inject10-s0\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"N/A\", \"model_name\": \"v4_random_fixed_inject10_s0\", \"seed\": 0, \"wall_clock_seconds\": 3975.6, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 Random 10% seed=0 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-taxei-fixed-inject10-s123-eval\": {\"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"187785\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123-eval.log\", \"submitted_at\": \"2026-05-15T18:57:40.646Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s123\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s123\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"N/A\", \"model_name\": \"v4_taxei_fixed_inject10_s123\", \"seed\": 123, \"wall_clock_seconds\": 3977.2, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 TaxEI 10% seed=123 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-taxei-fixed-inject10-s1-eval\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_fixed_inject10_s1_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"188906\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1-eval.log\", \"submitted_at\": \"2026-05-15T18:57:44.756Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s1\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"data_path\": \"eval/eval_tasks_47.json\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"wall_clock_seconds\": 3927.9, \"gpu_hours\": 1.09}, \"hypothesis\": \"v4 TaxEI 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-random-fixed-inject10-s123-eval\": {\"hypothesis\": \"v4 Random fixed-size 10% injection seed=123 eval — 47 ALFWorld tasks, dose-response 5-seed expansion\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s123/v0-20260516-015429/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_fixed_inject10_s123_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s123\", \"eval_data\": \"eval/eval_tasks_47.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123-eval.log\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}}, \"v4-taxei-fixed-inject10-s0-eval\": {\"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"188410\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s0-eval.log\", \"submitted_at\": \"2026-05-15T18:57:46.725Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s0\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s0\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"eval_results/v4_taxei_fixed_inject10_s0_eval.json\", \"model_name\": \"v4_taxei_fixed_inject10_s0\", \"seed\": 0, \"wall_clock_seconds\": 3970.2, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 TaxEI 10% seed=0 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.702, \"successes\": 33, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 8, \"rate\": 0.727}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}}, \"v4-taxei-fixed-inject10-s1\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 1 --data_seed 1 --output_dir checkpoints/v4_taxei_fixed_inject10_s1 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"182703\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1.log\", \"submitted_at\": \"2026-05-15T17:54:17.595Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635\", \"wall_clock_seconds\": 3728.4, \"gpu_hours\": 1.04}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion.\", \"metrics\": {\"final_loss\": 0.3013, \"train_loss_avg\": 0.4225, \"final_token_acc\": 0.8947, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3469, \"memory_gib\": 18.13, \"train_speed_s_per_it\": 2.121}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject10-s123\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --data_seed 123 --output_dir checkpoints/v4_random_fixed_inject10_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"182781\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123.log\", \"submitted_at\": \"2026-05-15T17:54:20.028Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 3802.4, \"gpu_hours\": 1.06}, \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=123 (4,358 total). Dose-response 5-seed expansion.\", \"metrics\": {\"final_loss\": 0.3124, \"train_loss_avg\": 0.4236, \"final_token_acc\": 0.8867, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3535.7, \"train_samples_per_second\": 3.698, \"train_steps_per_second\": 0.462, \"memory_gib\": 18.95}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-s123\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --data_seed 123 --output_dir checkpoints/v4_taxei_fixed_inject10_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"180877\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123.log\", \"submitted_at\": \"2026-05-15T17:48:23.907Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\", \"wall_clock_seconds\": 4085.3, \"gpu_hours\": 1.13}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=123 (4,358 total = 3,922 clean + 436 injected). Dose-response 5-seed expansion — 补齐 10% 数据点。\", \"metrics\": {\"train_loss\": 0.4234, \"final_loss\": 0.3097, \"final_token_acc\": 0.8882, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3497, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\"}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject10-s0\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --data_seed 0 --output_dir checkpoints/v4_random_fixed_inject10_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"180956\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0.log\", \"submitted_at\": \"2026-05-15T17:48:26.104Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\", \"wall_clock_seconds\": 4081.8, \"gpu_hours\": 1.13}, \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=0 (4,358 total). Dose-response 5-seed expansion — 与 TaxEI 10% 对比 taxonomy 标签效果。\", \"metrics\": {\"train_loss\": 0.4227, \"final_loss\": 0.276, \"final_token_acc\": 0.9067, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3531, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\"}, \"conclusion\": \"success\"}, \"v4-training-dynamics-forward-v2\": {\"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=2 bash scripts/run_training_dynamics_v2.sh\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"180322\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-training-dynamics-forward-v2.log\", \"submitted_at\": \"2026-05-15T16:56:31.040Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"training_dynamics\", \"data_count\": 0, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\", \"wall_clock_seconds\": 3546.9, \"gpu_hours\": 0.99}, \"conclusion\": \"success\", \"metrics\": {\"subsets_computed\": [\"vanilla_full\", \"taxei_full\", \"random_full\", \"taxei_inject10\", \"taxei_inject25\", \"taxei_inject50\"], \"taxei_inject50_injected_mean_loss\": 0.8185, \"taxei_inject50_clean_mean_loss\": 0.8514, \"per_operator\": {\"C1_ContextTruncation\": {\"mean\": 0.6489, \"n\": 101}, \"C4_ObservationMasking\": {\"mean\": 0.6782, \"n\": 92}, \"P1_StepOrderSwap\": {\"mean\": 0.6374, \"n\": 89}, \"P2_SubGoalDeletion\": {\"mean\": 0.6542, \"n\": 88}}, \"plots\": [\"subset_comparison\", \"operator_breakdown\", \"dose_response\"], \"output_dir\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\"}}, \"v4-taxei-fixed-inject10-s0\": {\"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=0 (4,358 total = 3,922 clean + 436 injected). Dose-response 5-seed expansion — 10% 是最薄弱环节，仅有 seed=42 一个数据点。\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"injection_ratio\": 0.1, \"clean_count\": 3922, \"injected_count\": 436, \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --data_seed 0 --output_dir checkpoints/v4_taxei_fixed_inject10_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\", \"log_path\": \"checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/logging.jsonl\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4238, \"final_loss\": 0.3102, \"final_token_acc\": 0.8822, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3494, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\"}}, \"v4-random-seed7-eval\": {\"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_seed7_eval.json\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"179098\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed7-eval.log\", \"submitted_at\": \"2026-05-15T17:29:24.122Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random SFT seed=7)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-seed7\", \"eval_data\": \"eval_tasks_47.json\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387\", \"wall_clock_seconds\": 852.6, \"gpu_hours\": 0.24}, \"hypothesis\": \"v4 Random SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion ← 基于 v4-random-seed7\", \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}, \"conclusion\": \"success\"}, \"v4-random-seed1-eval\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && mkdir -p eval_results && CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_seed1_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"178005\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed1-eval.log\", \"submitted_at\": \"2026-05-15T17:18:03.664Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 872.9, \"gpu_hours\": 0.24}, \"metrics\": {\"success_rate\": 0.468, \"successes\": 22, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 2, \"total\": 8, \"rate\": 0.25}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 2, \"total\": 7, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}}}, \"conclusion\": \"success\"}, \"v4-random-seed7\": {\"hypothesis\": \"v4 Random SFT seed=7 (5-seed expansion) — 9,029 samples, LoRA rank=16, 3 epochs\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_random_v4.jsonl --lora_rank 16 --lora_alpha 32 --num_train_epochs 3 --seed 7 --output_dir checkpoints/mini_random_sft_v4_seed7 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"gpu\": \"cuda:1\", \"pid\": 164126, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed7.log\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427\"}, \"metrics\": {\"final_loss\": 0.173, \"final_token_acc\": 0.935, \"initial_loss\": 4.017, \"total_steps\": 3387, \"epochs\": 3, \"total_flos\": 697192362530058200, \"train_runtime_sec\": 6672, \"memory_gib\": 18.49}, \"conclusion\": \"success\"}, \"v4-random-seed1\": {\"spec\": {\"hypothesis\": \"v4 Random SFT seed=1 (5-seed expansion) — 9,029 samples, LoRA rank=16, 3 epochs\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 train/sft_train.py --config configs/mini_random_sft_v4_seed1.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_random_v4\", \"data_count\": 1129, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"gpu\": [\"cuda:0\"], \"pid\": \"163009\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed1.log\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/\", \"submitted_at\": \"2026-05-15T15:23:31Z\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 6842.6, \"gpu_hours\": 1.9}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.167, \"final_token_acc\": 0.938, \"initial_loss\": 4.017, \"total_steps\": 3387, \"epochs\": 3, \"total_flos\": 697000000000000000}}, \"v4-taxei-seed1-eval\": {\"hypothesis\": \"v4 TaxEI SFT seed=1 eval — 47 ALFWorld tasks, 5-seed expansion\", \"spec\": {\"command\": \"python eval_agent.py --checkpoint checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387 --split valid_unseen\", \"server\": \"autodl-5090\", \"data_path\": \"valid_unseen\", \"data_count\": 47, \"model_name\": \"mini_taxei_sft_v4_seed1/checkpoint-3387\", \"seed\": 1, \"checkpoint_source\": \"v4-taxei-seed1\", \"eval_data\": \"valid_unseen\", \"gpu\": [\"cuda:2\"], \"pid\": 173824, \"log_path\": \"eval_results/v4_taxei_seed1_eval.json\", \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\", \"parent\": \"v4-taxei-seed1\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.596, \"successes\": 28, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}}, \"v4-vanilla-seed1-eval\": {\"hypothesis\": \"v4 Vanilla SFT seed=1 eval — 47 ALFWorld tasks, 5-seed expansion\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_vanilla_seed1_eval.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=1)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"gpu\": [\"cuda:0\"]}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.66, \"eval_successes\": 31, \"eval_total\": 47, \"vs_seed42_pp\": 4.3}}, \"v4-taxei-seed7-eval\": {\"hypothesis\": \"v4 TaxEI SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_seed7_eval.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (TaxEI v4 seed=7)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-taxei-seed7\", \"gpu\": [\"cuda:3\"], \"pid\": \"165338\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed7-eval.log\", \"checkpoint_path\": \"eval_results/v4_taxei_seed7_eval.json\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.617, \"successes\": 29, \"total\": 47, \"by_task\": {\"look_at_obj_in_light\": \"4/6 (0.667)\", \"pick_and_place_simple\": \"5/8 (0.625)\", \"pick_clean_then_place_in_recep\": \"5/11 (0.455)\", \"pick_cool_then_place_in_recep\": \"4/7 (0.571)\", \"pick_heat_then_place_in_recep\": \"7/8 (0.875)\", \"pick_two_obj_and_place\": \"4/7 (0.571)\"}}}, \"v4-training-dynamics-forward\": {\"hypothesis\": \"D027 Training Dynamics: Post-hoc forward pass on seed=42 checkpoints (Vanilla/TaxEI/Random + dose-response 10%/25%/50%) — compute per-subset loss (clean vs injected) and per-operator loss (P1/P2/C1/C4). Key finding: training loss SD=0.0004 across seeds but eval SD=8.6pp — memorization-generalization dissociation.\", \"spec\": {\"command\": \"bash scripts/run_training_dynamics.sh\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/\", \"data_count\": 6, \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"metrics\": {\"vanilla_full\": {\"clean_loss\": 0.6853, \"clean_n\": 4358}, \"taxei_full\": {\"clean_loss\": 0.7712, \"injected_loss\": 0.6139, \"clean_n\": 8269, \"injected_n\": 760, \"per_operator\": {\"P1_StepOrderSwap\": 0.6165, \"P2_SubGoalDeletion\": 0.6161, \"C1_ContextTruncation\": 0.5932, \"C4_ObservationMasking\": 0.6298}}, \"random_full\": {\"clean_loss\": 0.7354, \"injected_loss\": 0.5902, \"clean_n\": 8269, \"injected_n\": 760}, \"dose_response\": {\"taxei_10pct\": {\"clean_loss\": 0.6628, \"injected_loss\": 0.6464, \"gap\": -0.0164, \"injected_n\": 70}, \"taxei_25pct\": {\"clean_loss\": 0.701, \"injected_loss\": 0.574, \"gap\": -0.127, \"injected_n\": 168}, \"taxei_50pct\": {\"clean_loss\": 0.8516, \"injected_loss\": 0.6547, \"gap\": -0.1969, \"injected_n\": 370}}, \"key_findings\": \"Clear dose-response: injected-clean gap widens from -0.016 (10%) to -0.127 (25%) to -0.197 (50%). TaxEI operators C1_ContextTruncation consistently lowest loss. Higher injection rates also degrade clean sample loss (0.663→0.701→0.852).\"}, \"conclusion\": \"success\"}, \"v4-taxei-seed1\": {\"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 1 --lora_rank 16 --lora_alpha 32 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"gpu\": \"cuda:2\", \"pid\": 154937}, \"metrics\": {\"final_loss\": 0.1667, \"avg_loss\": 0.3561, \"token_accuracy\": 0.915, \"final_token_acc\": 0.942, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 108.9, \"memory_gib\": 18.49, \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\"}, \"conclusion\": \"success\"}, \"v4-taxei-seed7\": {\"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 7 --lora_rank 16 --lora_alpha 32 --3epochs\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"gpu\": \"cuda:3\", \"pid\": 155145}, \"metrics\": {\"current_step\": 3387, \"total_steps\": 3387, \"progress_pct\": 100, \"train_loss\": 0.3568, \"final_step_loss\": 0.1753, \"token_acc\": 0.9009, \"final_token_acc\": 0.9328, \"train_runtime_s\": 6591.9, \"epochs\": 3, \"peak_memory_gib\": 18.49, \"gpu\": \"cuda:3\", \"pid\": 155145}, \"conclusion\": \"success\"}, \"v4-vanilla-seed7-eval\": {\"hypothesis\": \"v4 Vanilla SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --num_episodes 47 --output eval_results/v4_vanilla_seed7_eval.json --device cuda:1 --seed 42\", \"server\": \"autodl-5090\", \"data_path\": \"eval/47 ALFWorld valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=7)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-vanilla-seed7\", \"gpu\": [\"cuda:1\"], \"pid\": \"160587\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-seed7-eval.log\", \"checkpoint_path\": \"eval_results/v4_vanilla_seed7_eval.json\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.745, \"eval_successes\": 35, \"eval_total\": 47, \"vs_seed42_pp\": 12.8}}}, \"count\": 30, \"total\": 66, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.267}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b4dedea6-c2e8-4788-a3d2-994037e3272a",
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "5a0af7a1-1a87-4f20-bea8-827ac47089bb",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {\\\"v4-random-fixed-inject10-s7\\\": {\\\"hypothesis\\\": \\\"v4 Random fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion — 最后一个 10% 训练。\\\", \\\"spec\\\": {\\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (random fixed inject10 s7)\\\", \\\"seed\\\": 7}, \\\"metrics\\\": {\\\"final_loss\\\": 0.2352, \\\"train_loss_avg\\\": 0.4209, \\\"final_token_acc\\\": 0.9066, \\\"total_steps\\\": 1635, \\\"epochs\\\": 3, \\\"train_runtime_sec\\\": 3511.93, \\\"memory_gib\\\": 18.15, \\\"train_speed_s_per_it\\\": 2.148}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-random-fixed-inject10-s1-eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635 --num_episodes 47 --seed 42\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"198045\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s1-eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T21:05:18.393Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (random fixed inject10 s1)\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"v4-random-fixed-inject10-s1\\\", \\\"eval_data\\\": \\\"eval_tasks_47.json\\\", \\\"checkpoint_path\\\": \\\"checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635\\\", \\\"wall_clock_seconds\\\": 1350.0, \\\"gpu_hours\\\": 0.37}, \\\"hypothesis\\\": \\\"v4 Random 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.681, \\\"successes\\\": 32, \\\"total\\\": 47, \\\"by_task_type\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 5, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 5, \\\"rate\\\": 0.625}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 10, \\\"success\\\": 5, \\\"rate\\\": 0.5}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 6, \\\"rate\\\": 0.857}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 7, \\\"rate\\\": 0.875}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 4, \\\"rate\\\": 0.571}}}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-taxei-fixed-inject10-s7-eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject10_s7/v1-20260516-040128/checkpoint-1635 --num_episodes 47 --seed 42\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"197555\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s7-eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T21:02:21.785Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (taxei fixed inject10 s7)\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"v4-taxei-fixed-inject10-s7\\\", \\\"eval_data\\\": \\\"eval_tasks_47.json\\\", \\\"wall_clock_seconds\\\": 1522.4, \\\"gpu_hours\\\": 0.42}, \\\"hypothesis\\\": \\\"v4 TaxEI 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.681, \\\"successes\\\": 32, \\\"total\\\": 47, \\\"by_task_type\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 5, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 5, \\\"rate\\\": 0.625}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 11, \\\"success\\\": 7, \\\"rate\\\": 0.636}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 4, \\\"rate\\\": 0.571}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 7, \\\"rate\\\": 0.875}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 4, \\\"rate\\\": 0.571}}}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-taxei-fixed-inject10-s1-eval-r2\\\": {\\\"spec\\\": {\\\"parent\\\": \\\"v4-taxei-fixed-inject10-s1\\\", \\\"checkpoint_source\\\": \\\"v4-taxei-fixed-inject10-s1\\\", \\\"eval_data\\\": \\\"eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (taxei fixed inject10 s1)\\\", \\\"seed\\\": 42, \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\"}, \\\"hypothesis\\\": \\\"v4 TaxEI 10% seed=1 eval (r2, dedicated GPU) — 47 ALFWorld clean tasks.\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.511, \\\"successes\\\": 24, \\\"total\\\": 47, \\\"by_task_type\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 4, \\\"rate\\\": 0.667}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 4, \\\"rate\\\": 0.5}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 11, \\\"success\\\": 5, \\\"rate\\\": 0.455}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 2, \\\"rate\\\": 0.286}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 6, \\\"rate\\\": 0.75}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 3, \\\"rate\\\": 0.429}}}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-taxei-fixed-inject10-s7\\\": {\\\"hypothesis\\\": \\\"v4 TaxEI fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion.\\\", \\\"spec\\\": {\\\"command\\\": \\\"swift sft --model Qwen3-8B --dataset sft_taxei_v4_fixed_inject10.jsonl --seed 7\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"191997\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s7.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T20:01:19.314Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 7, \\\"wall_clock_seconds\\\": 3683.3, \\\"gpu_hours\\\": 1.02}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.237, \\\"train_loss_avg\\\": 0.4212, \\\"final_token_acc\\\": 0.905, \\\"total_steps\\\": 1635, \\\"epochs\\\": 3, \\\"train_runtime_sec\\\": 3437, \\\"memory_gib\\\": 18.15, \\\"train_speed_s_per_it\\\": 2.102}}, \\\"v4-random-fixed-inject10-s1\\\": {\\\"hypothesis\\\": \\\"v4 Random fixed-size ablation: 10% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion.\\\", \\\"spec\\\": {\\\"command\\\": \\\"swift sft --model Qwen3-8B --dataset sft_random_v4_fixed_inject10.jsonl --seed 1\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"192077\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s1.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T20:01:21.468Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 1, \\\"wall_clock_seconds\\\": 3782.3, \\\"gpu_hours\\\": 1.05}, \\\"metrics\\\": {\\\"final_loss\\\": 0.3096, \\\"train_loss_avg\\\": 0.4238, \\\"final_token_acc\\\": 0.8902, \\\"total_steps\\\": 1635, \\\"epochs\\\": 3, \\\"train_runtime_sec\\\": 3488, \\\"memory_gib\\\": 18.13, \\\"train_speed_s_per_it\\\": 2.132}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-taxei-fixed-inject10-s123-eval-r3\\\": {\\\"spec\\\": {\\\"command\\\": \\\"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635 --num_episodes 47 --seed 42\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"194978\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123-eval-r3.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T20:40:05.519Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"parent\\\": \\\"v4-taxei-fixed-inject10-s123\\\", \\\"checkpoint_source\\\": \\\"v4-taxei-fixed-inject10-s123\\\", \\\"eval_data\\\": \\\"eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (taxei fixed inject10 s123)\\\", \\\"seed\\\": 42, \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\", \\\"wall_clock_seconds\\\": 848.9, \\\"gpu_hours\\\": 0.24}, \\\"hypothesis\\\": \\\"v4 TaxEI 10% seed=123 eval (r3, dedicated GPU) — 47 ALFWorld clean tasks.\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.553, \\\"successes\\\": 26, \\\"total\\\": 47, \\\"by_task_type\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 5, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 4, \\\"rate\\\": 0.5}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 11, \\\"success\\\": 5, \\\"rate\\\": 0.455}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 2, \\\"rate\\\": 0.286}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 6, \\\"rate\\\": 0.75}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 4, \\\"rate\\\": 0.571}}}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-random-fixed-inject10-s0-eval-r3\\\": {\\\"spec\\\": {\\\"command\\\": \\\"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635 --num_episodes 47 --seed 42\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"195118\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0-eval-r3.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T20:40:07.156Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"parent\\\": \\\"v4-random-fixed-inject10-s0\\\", \\\"checkpoint_source\\\": \\\"v4-random-fixed-inject10-s0\\\", \\\"eval_data\\\": \\\"eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (random fixed inject10 s0)\\\", \\\"seed\\\": 42, \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\", \\\"wall_clock_seconds\\\": 745.0, \\\"gpu_hours\\\": 0.21}, \\\"hypothesis\\\": \\\"v4 Random 10% seed=0 eval (r3, dedicated GPU) — 47 ALFWorld clean tasks.\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.66, \\\"successes\\\": 31, \\\"total\\\": 47, \\\"by_task_type\\\": {\\\"look_at_obj_in_light\\\": {\\\"success\\\": 5, \\\"total\\\": 6, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"success\\\": 4, \\\"total\\\": 8, \\\"rate\\\": 0.5}, \\\"pick_clean_then_place_in_recep\\\": {\\\"success\\\": 7, \\\"total\\\": 11, \\\"rate\\\": 0.636}, \\\"pick_cool_then_place_in_recep\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}, \\\"pick_heat_then_place_in_recep\\\": {\\\"success\\\": 7, \\\"total\\\": 8, \\\"rate\\\": 0.875}, \\\"pick_two_obj_and_place\\\": {\\\"success\\\": 4, \\\"total\\\": 7, \\\"rate\\\": 0.571}}}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-random-fixed-inject10-s0-eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"eval\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"188022\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0-eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T18:57:43.056Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"parent\\\": \\\"v4-random-fixed-inject10-s0\\\", \\\"checkpoint_source\\\": \\\"v4-random-fixed-inject10-s0\\\", \\\"eval_data\\\": \\\"valid_unseen\\\", \\\"data_count\\\": 47, \\\"data_path\\\": \\\"N/A\\\", \\\"model_name\\\": \\\"v4_random_fixed_inject10_s0\\\", \\\"seed\\\": 0, \\\"wall_clock_seconds\\\": 3975.6, \\\"gpu_hours\\\": 1.1}, \\\"hypothesis\\\": \\\"v4 Random 10% seed=0 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\\", \\\"conclusion\\\": \\\"failed\\\", \\\"metrics\\\": {\\\"error\\\": \\\"CUDA OOM during model loading on GPU 0\\\"}}, \\\"v4-taxei-fixed-inject10-s123-eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"eval\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"187785\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123-eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T18:57:40.646Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"parent\\\": \\\"v4-taxei-fixed-inject10-s123\\\", \\\"checkpoint_source\\\": \\\"v4-taxei-fixed-inject10-s123\\\", \\\"eval_data\\\": \\\"valid_unseen\\\", \\\"data_count\\\": 47, \\\"data_path\\\": \\\"N/A\\\", \\\"model_name\\\": \\\"v4_taxei_fixed_inject10_s123\\\", \\\"seed\\\": 123, \\\"wall_clock_seconds\\\": 3977.2, \\\"gpu_hours\\\": 1.1}, \\\"hypothesis\\\": \\\"v4 TaxEI 10% seed=123 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\\", \\\"conclusion\\\": \\\"failed\\\", \\\"metrics\\\": {\\\"error\\\": \\\"CUDA OOM during model loading on GPU 0\\\"}}, \\\"v4-taxei-fixed-inject10-s1-eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_fixed_inject10_s1_eval.json\\\\\\\"\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"188906\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1-eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T18:57:44.756Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"parent\\\": \\\"v4-taxei-fixed-inject10-s1\\\", \\\"checkpoint_source\\\": \\\"v4-taxei-fixed-inject10-s1\\\", \\\"eval_data\\\": \\\"eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\", \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"wall_clock_seconds\\\": 3927.9, \\\"gpu_hours\\\": 1.09}, \\\"hypothesis\\\": \\\"v4 TaxEI 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\\", \\\"conclusion\\\": \\\"failed\\\", \\\"metrics\\\": {\\\"error\\\": \\\"CUDA OOM during model loading on GPU 0\\\"}}, \\\"v4-random-fixed-inject10-s123-eval\\\": {\\\"hypothesis\\\": \\\"v4 Random fixed-size 10% injection seed=123 eval — 47 ALFWorld tasks, dose-response 5-seed expansion\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s123/v0-20260516-015429/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_fixed_inject10_s123_eval.json\\\\\\\"\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"v4-random-fixed-inject10-s123\\\", \\\"eval_data\\\": \\\"eval/eval_tasks_47.json\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123-eval.log\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\"}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.553, \\\"successes\\\": 26, \\\"total\\\": 47, \\\"by_task_type\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 5, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 5, \\\"rate\\\": 0.625}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 11, \\\"success\\\": 5, \\\"rate\\\": 0.455}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 2, \\\"rate\\\": 0.286}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 6, \\\"rate\\\": 0.75}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 3, \\\"rate\\\": 0.429}}}}, \\\"v4-taxei-fixed-inject10-s0-eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"eval\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"188410\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s0-eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T18:57:46.725Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"parent\\\": \\\"v4-taxei-fixed-inject10-s0\\\", \\\"checkpoint_source\\\": \\\"v4-taxei-fixed-inject10-s0\\\", \\\"eval_data\\\": \\\"valid_unseen\\\", \\\"data_count\\\": 47, \\\"data_path\\\": \\\"eval_results/v4_taxei_fixed_inject10_s0_eval.json\\\", \\\"model_name\\\": \\\"v4_taxei_fixed_inject10_s0\\\", \\\"seed\\\": 0, \\\"wall_clock_seconds\\\": 3970.2, \\\"gpu_hours\\\": 1.1}, \\\"hypothesis\\\": \\\"v4 TaxEI 10% seed=0 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.702, \\\"successes\\\": 33, \\\"total\\\": 47, \\\"by_task_type\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 5, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 5, \\\"rate\\\": 0.625}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 11, \\\"success\\\": 8, \\\"rate\\\": 0.727}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 4, \\\"rate\\\": 0.571}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 7, \\\"rate\\\": 0.875}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 4, \\\"rate\\\": 0.571}}}}, \\\"v4-taxei-fixed-inject10-s1\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 1 --data_seed 1 --output_dir checkpoints/v4_taxei_fixed_inject10_s1 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\\\\\"\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"182703\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T17:54:17.595Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 1, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635\\\", \\\"wall_clock_seconds\\\": 3728.4, \\\"gpu_hours\\\": 1.04}, \\\"hypothesis\\\": \\\"v4 TaxEI fixed-size ablation: 10% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion.\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.3013, \\\"train_loss_avg\\\": 0.4225, \\\"final_token_acc\\\": 0.8947, \\\"total_steps\\\": 1635, \\\"epochs\\\": 3, \\\"train_runtime_sec\\\": 3469, \\\"memory_gib\\\": 18.13, \\\"train_speed_s_per_it\\\": 2.121}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-random-fixed-inject10-s123\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --data_seed 123 --output_dir checkpoints/v4_random_fixed_inject10_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\\\\\"\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"182781\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T17:54:20.028Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 123, \\\"wall_clock_seconds\\\": 3802.4, \\\"gpu_hours\\\": 1.06}, \\\"hypothesis\\\": \\\"v4 Random fixed-size ablation: 10% injection ratio seed=123 (4,358 total). Dose-response 5-seed expansion.\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.3124, \\\"train_loss_avg\\\": 0.4236, \\\"final_token_acc\\\": 0.8867, \\\"total_steps\\\": 1635, \\\"epochs\\\": 3, \\\"train_runtime_sec\\\": 3535.7, \\\"train_samples_per_second\\\": 3.698, \\\"train_steps_per_second\\\": 0.462, \\\"memory_gib\\\": 18.95}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-taxei-fixed-inject10-s123\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --data_seed 123 --output_dir checkpoints/v4_taxei_fixed_inject10_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\\\\\"\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"180877\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T17:48:23.907Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 123, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\\\", \\\"wall_clock_seconds\\\": 4085.3, \\\"gpu_hours\\\": 1.13}, \\\"hypothesis\\\": \\\"v4 TaxEI fixed-size ablation: 10% injection ratio seed=123 (4,358 total = 3,922 clean + 436 injected). Dose-response 5-seed expansion — 补齐 10% 数据点。\\\", \\\"metrics\\\": {\\\"train_loss\\\": 0.4234, \\\"final_loss\\\": 0.3097, \\\"final_token_acc\\\": 0.8882, \\\"epochs\\\": 3, \\\"total_steps\\\": 1635, \\\"train_runtime_sec\\\": 3497, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-random-fixed-inject10-s0\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --data_seed 0 --output_dir checkpoints/v4_random_fixed_inject10_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\\\\\"\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"180956\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T17:48:26.104Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 0, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\\\", \\\"wall_clock_seconds\\\": 4081.8, \\\"gpu_hours\\\": 1.13}, \\\"hypothesis\\\": \\\"v4 Random fixed-size ablation: 10% injection ratio seed=0 (4,358 total). Dose-response 5-seed expansion — 与 TaxEI 10% 对比 taxonomy 标签效果。\\\", \\\"metrics\\\": {\\\"train_loss\\\": 0.4227, \\\"final_loss\\\": 0.276, \\\"final_token_acc\\\": 0.9067, \\\"epochs\\\": 3, \\\"total_steps\\\": 1635, \\\"train_runtime_sec\\\": 3531, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-training-dynamics-forward-v2\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=2 bash scripts/run_training_dynamics_v2.sh\\\\\\\"\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": \\\"180322\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-training-dynamics-forward-v2.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T16:56:31.040Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"training_dynamics\\\", \\\"data_count\\\": 0, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\\\", \\\"wall_clock_seconds\\\": 3546.9, \\\"gpu_hours\\\": 0.99}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"subsets_computed\\\": [\\\"vanilla_full\\\", \\\"taxei_full\\\", \\\"random_full\\\", \\\"taxei_inject10\\\", \\\"taxei_inject25\\\", \\\"taxei_inject50\\\"], \\\"taxei_inject50_injected_mean_loss\\\": 0.8185, \\\"taxei_inject50_clean_mean_loss\\\": 0.8514, \\\"per_operator\\\": {\\\"C1_ContextTruncation\\\": {\\\"mean\\\": 0.6489, \\\"n\\\": 101}, \\\"C4_ObservationMasking\\\": {\\\"mean\\\": 0.6782, \\\"n\\\": 92}, \\\"P1_StepOrderSwap\\\": {\\\"mean\\\": 0.6374, \\\"n\\\": 89}, \\\"P2_SubGoalDeletion\\\": {\\\"mean\\\": 0.6542, \\\"n\\\": 88}}, \\\"plots\\\": [\\\"subset_comparison\\\", \\\"operator_breakdown\\\", \\\"dose_response\\\"], \\\"output_dir\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\\\"}}, \\\"v4-taxei-fixed-inject10-s0\\\": {\\\"hypothesis\\\": \\\"v4 TaxEI fixed-size ablation: 10% injection ratio seed=0 (4,358 total = 3,922 clean + 436 injected). Dose-response 5-seed expansion — 10% 是最薄弱环节，仅有 seed=42 一个数据点。\\\", \\\"spec\\\": {\\\"data_path\\\": \\\"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\\\", \\\"data_count\\\": 4358, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 0, \\\"injection_ratio\\\": 0.1, \\\"clean_count\\\": 3922, \\\"injected_count\\\": 436, \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --data_seed 0 --output_dir checkpoints/v4_taxei_fixed_inject10_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\\\\\"\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\\\", \\\"log_path\\\": \\\"checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/logging.jsonl\\\"}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss\\\": 0.4238, \\\"final_loss\\\": 0.3102, \\\"final_token_acc\\\": 0.8822, \\\"epochs\\\": 3, \\\"total_steps\\\": 1635, \\\"train_runtime_sec\\\": 3494, \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\\\"}}, \\\"v4-random-seed7-eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_seed7_eval.json\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"179098\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-seed7-eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T17:29:24.122Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (random SFT seed=7)\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"v4-random-seed7\\\", \\\"eval_data\\\": \\\"eval_tasks_47.json\\\", \\\"checkpoint_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387\\\", \\\"wall_clock_seconds\\\": 852.6, \\\"gpu_hours\\\": 0.24}, \\\"hypothesis\\\": \\\"v4 Random SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion ← 基于 v4-random-seed7\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.553, \\\"successes\\\": 26, \\\"total\\\": 47, \\\"by_task_type\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 5, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 4, \\\"rate\\\": 0.5}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 11, \\\"success\\\": 6, \\\"rate\\\": 0.545}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 3, \\\"rate\\\": 0.429}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 5, \\\"rate\\\": 0.625}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 3, \\\"rate\\\": 0.429}}}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-random-seed1-eval\\\": {\\\"spec\\\": {\\\"command\\\": \\\"bash -c \\\\\\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && mkdir -p eval_results && CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_seed1_eval.json\\\\\\\"\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"178005\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-seed1-eval.log\\\", \\\"submitted_at\\\": \\\"2026-05-15T17:18:03.664Z\\\", \\\"submitted_via\\\": \\\"submit_training_job\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 872.9, \\\"gpu_hours\\\": 0.24}, \\\"metrics\\\": {\\\"success_rate\\\": 0.468, \\\"successes\\\": 22, \\\"total\\\": 47, \\\"by_task_type\\\": {\\\"look_at_obj_in_light\\\": {\\\"success\\\": 5, \\\"total\\\": 6, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"success\\\": 2, \\\"total\\\": 8, \\\"rate\\\": 0.25}, \\\"pick_clean_then_place_in_recep\\\": {\\\"success\\\": 5, \\\"total\\\": 11, \\\"rate\\\": 0.455}, \\\"pick_cool_then_place_in_recep\\\": {\\\"success\\\": 2, \\\"total\\\": 7, \\\"rate\\\": 0.286}, \\\"pick_heat_then_place_in_recep\\\": {\\\"success\\\": 5, \\\"total\\\": 8, \\\"rate\\\": 0.625}, \\\"pick_two_obj_and_place\\\": {\\\"success\\\": 3, \\\"total\\\": 7, \\\"rate\\\": 0.429}}}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-random-seed7\\\": {\\\"hypothesis\\\": \\\"v4 Random SFT seed=7 (5-seed expansion) — 9,029 samples, LoRA rank=16, 3 epochs\\\", \\\"spec\\\": {\\\"command\\\": \\\"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_random_v4.jsonl --lora_rank 16 --lora_alpha 32 --num_train_epochs 3 --seed 7 --output_dir checkpoints/mini_random_sft_v4_seed7 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/sft_random_v4.jsonl\\\", \\\"data_count\\\": 9029, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 7, \\\"gpu\\\": \\\"cuda:1\\\", \\\"pid\\\": 164126, \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-seed7.log\\\", \\\"checkpoint_path\\\": \\\"checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427\\\"}, \\\"metrics\\\": {\\\"final_loss\\\": 0.173, \\\"final_token_acc\\\": 0.935, \\\"initial_loss\\\": 4.017, \\\"total_steps\\\": 3387, \\\"epochs\\\": 3, \\\"total_flos\\\": 697192362530058200, \\\"train_runtime_sec\\\": 6672, \\\"memory_gib\\\": 18.49}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-random-seed1\\\": {\\\"spec\\\": {\\\"hypothesis\\\": \\\"v4 Random SFT seed=1 (5-seed expansion) — 9,029 samples, LoRA rank=16, 3 epochs\\\", \\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python3 train/sft_train.py --config configs/mini_random_sft_v4_seed1.yaml\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"data_path\\\": \\\"data/mini_random_v4\\\", \\\"data_count\\\": 1129, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 1, \\\"gpu\\\": [\\\"cuda:0\\\"], \\\"pid\\\": \\\"163009\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-random-seed1.log\\\", \\\"checkpoint_path\\\": \\\"checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/\\\", \\\"submitted_at\\\": \\\"2026-05-15T15:23:31Z\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\", \\\"wall_clock_seconds\\\": 6842.6, \\\"gpu_hours\\\": 1.9}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"final_loss\\\": 0.167, \\\"final_token_acc\\\": 0.938, \\\"initial_loss\\\": 4.017, \\\"total_steps\\\": 3387, \\\"epochs\\\": 3, \\\"total_flos\\\": 697000000000000000}}, \\\"v4-taxei-seed1-eval\\\": {\\\"hypothesis\\\": \\\"v4 TaxEI SFT seed=1 eval — 47 ALFWorld tasks, 5-seed expansion\\\", \\\"spec\\\": {\\\"command\\\": \\\"python eval_agent.py --checkpoint checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387 --split valid_unseen\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"data_path\\\": \\\"valid_unseen\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"mini_taxei_sft_v4_seed1/checkpoint-3387\\\", \\\"seed\\\": 1, \\\"checkpoint_source\\\": \\\"v4-taxei-seed1\\\", \\\"eval_data\\\": \\\"valid_unseen\\\", \\\"gpu\\\": [\\\"cuda:2\\\"], \\\"pid\\\": 173824, \\\"log_path\\\": \\\"eval_results/v4_taxei_seed1_eval.json\\\", \\\"checkpoint_path\\\": \\\"checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\\\", \\\"parent\\\": \\\"v4-taxei-seed1\\\"}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.596, \\\"successes\\\": 28, \\\"total\\\": 47, \\\"by_task_type\\\": {\\\"look_at_obj_in_light\\\": {\\\"total\\\": 6, \\\"success\\\": 5, \\\"rate\\\": 0.833}, \\\"pick_and_place_simple\\\": {\\\"total\\\": 8, \\\"success\\\": 4, \\\"rate\\\": 0.5}, \\\"pick_clean_then_place_in_recep\\\": {\\\"total\\\": 11, \\\"success\\\": 5, \\\"rate\\\": 0.455}, \\\"pick_cool_then_place_in_recep\\\": {\\\"total\\\": 7, \\\"success\\\": 2, \\\"rate\\\": 0.286}, \\\"pick_heat_then_place_in_recep\\\": {\\\"total\\\": 8, \\\"success\\\": 7, \\\"rate\\\": 0.875}, \\\"pick_two_obj_and_place\\\": {\\\"total\\\": 7, \\\"success\\\": 5, \\\"rate\\\": 0.714}}}}, \\\"v4-vanilla-seed1-eval\\\": {\\\"hypothesis\\\": \\\"v4 Vanilla SFT seed=1 eval — 47 ALFWorld tasks, 5-seed expansion\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_vanilla_seed1_eval.json\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (vanilla v4 seed=1)\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635\\\", \\\"eval_data\\\": \\\"47 ALFWorld tasks (clean, no injection)\\\", \\\"gpu\\\": [\\\"cuda:0\\\"]}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.66, \\\"eval_successes\\\": 31, \\\"eval_total\\\": 47, \\\"vs_seed42_pp\\\": 4.3}}, \\\"v4-taxei-seed7-eval\\\": {\\\"hypothesis\\\": \\\"v4 TaxEI SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion\\\", \\\"spec\\\": {\\\"command\\\": \\\"CUDA_VISIBLE_DEVICES=3 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_seed7_eval.json\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"data_path\\\": \\\"eval/eval_tasks_47.json\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (TaxEI v4 seed=7)\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387\\\", \\\"eval_data\\\": \\\"47 ALFWorld tasks (clean, no injection)\\\", \\\"parent\\\": \\\"v4-taxei-seed7\\\", \\\"gpu\\\": [\\\"cuda:3\\\"], \\\"pid\\\": \\\"165338\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-taxei-seed7-eval.log\\\", \\\"checkpoint_path\\\": \\\"eval_results/v4_taxei_seed7_eval.json\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\"}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"success_rate\\\": 0.617, \\\"successes\\\": 29, \\\"total\\\": 47, \\\"by_task\\\": {\\\"look_at_obj_in_light\\\": \\\"4/6 (0.667)\\\", \\\"pick_and_place_simple\\\": \\\"5/8 (0.625)\\\", \\\"pick_clean_then_place_in_recep\\\": \\\"5/11 (0.455)\\\", \\\"pick_cool_then_place_in_recep\\\": \\\"4/7 (0.571)\\\", \\\"pick_heat_then_place_in_recep\\\": \\\"7/8 (0.875)\\\", \\\"pick_two_obj_and_place\\\": \\\"4/7 (0.571)\\\"}}}, \\\"v4-training-dynamics-forward\\\": {\\\"hypothesis\\\": \\\"D027 Training Dynamics: Post-hoc forward pass on seed=42 checkpoints (Vanilla/TaxEI/Random + dose-response 10%/25%/50%) — compute per-subset loss (clean vs injected) and per-operator loss (P1/P2/C1/C4). Key finding: training loss SD=0.0004 across seeds but eval SD=8.6pp — memorization-generalization dissociation.\\\", \\\"spec\\\": {\\\"command\\\": \\\"bash scripts/run_training_dynamics.sh\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"data_path\\\": \\\"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/\\\", \\\"data_count\\\": 6, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 42}, \\\"metrics\\\": {\\\"vanilla_full\\\": {\\\"clean_loss\\\": 0.6853, \\\"clean_n\\\": 4358}, \\\"taxei_full\\\": {\\\"clean_loss\\\": 0.7712, \\\"injected_loss\\\": 0.6139, \\\"clean_n\\\": 8269, \\\"injected_n\\\": 760, \\\"per_operator\\\": {\\\"P1_StepOrderSwap\\\": 0.6165, \\\"P2_SubGoalDeletion\\\": 0.6161, \\\"C1_ContextTruncation\\\": 0.5932, \\\"C4_ObservationMasking\\\": 0.6298}}, \\\"random_full\\\": {\\\"clean_loss\\\": 0.7354, \\\"injected_loss\\\": 0.5902, \\\"clean_n\\\": 8269, \\\"injected_n\\\": 760}, \\\"dose_response\\\": {\\\"taxei_10pct\\\": {\\\"clean_loss\\\": 0.6628, \\\"injected_loss\\\": 0.6464, \\\"gap\\\": -0.0164, \\\"injected_n\\\": 70}, \\\"taxei_25pct\\\": {\\\"clean_loss\\\": 0.701, \\\"injected_loss\\\": 0.574, \\\"gap\\\": -0.127, \\\"injected_n\\\": 168}, \\\"taxei_50pct\\\": {\\\"clean_loss\\\": 0.8516, \\\"injected_loss\\\": 0.6547, \\\"gap\\\": -0.1969, \\\"injected_n\\\": 370}}, \\\"key_findings\\\": \\\"Clear dose-response: injected-clean gap widens from -0.016 (10%) to -0.127 (25%) to -0.197 (50%). TaxEI operators C1_ContextTruncation consistently lowest loss. Higher injection rates also degrade clean sample loss (0.663→0.701→0.852).\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-taxei-seed1\\\": {\\\"spec\\\": {\\\"command\\\": \\\"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 1 --lora_rank 16 --lora_alpha 32 --num_train_epochs 3\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/sft_taxei_v4.jsonl\\\", \\\"data_count\\\": 9029, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 1, \\\"gpu\\\": \\\"cuda:2\\\", \\\"pid\\\": 154937}, \\\"metrics\\\": {\\\"final_loss\\\": 0.1667, \\\"avg_loss\\\": 0.3561, \\\"token_accuracy\\\": 0.915, \\\"final_token_acc\\\": 0.942, \\\"train_steps\\\": 3387, \\\"train_epochs\\\": 3, \\\"train_duration_min\\\": 108.9, \\\"memory_gib\\\": 18.49, \\\"checkpoint_path\\\": \\\"checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\\\"}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-taxei-seed7\\\": {\\\"spec\\\": {\\\"command\\\": \\\"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 7 --lora_rank 16 --lora_alpha 32 --3epochs\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"data_path\\\": \\\"data/mini_pipeline_v4/sft_taxei_v4.jsonl\\\", \\\"data_count\\\": 9029, \\\"model_name\\\": \\\"Qwen3-8B\\\", \\\"seed\\\": 7, \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 155145}, \\\"metrics\\\": {\\\"current_step\\\": 3387, \\\"total_steps\\\": 3387, \\\"progress_pct\\\": 100, \\\"train_loss\\\": 0.3568, \\\"final_step_loss\\\": 0.1753, \\\"token_acc\\\": 0.9009, \\\"final_token_acc\\\": 0.9328, \\\"train_runtime_s\\\": 6591.9, \\\"epochs\\\": 3, \\\"peak_memory_gib\\\": 18.49, \\\"gpu\\\": \\\"cuda:3\\\", \\\"pid\\\": 155145}, \\\"conclusion\\\": \\\"success\\\"}, \\\"v4-vanilla-seed7-eval\\\": {\\\"hypothesis\\\": \\\"v4 Vanilla SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion\\\", \\\"spec\\\": {\\\"command\\\": \\\"python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --num_episodes 47 --output eval_results/v4_vanilla_seed7_eval.json --device cuda:1 --seed 42\\\", \\\"server\\\": \\\"autodl-5090\\\", \\\"data_path\\\": \\\"eval/47 ALFWorld valid_unseen\\\", \\\"data_count\\\": 47, \\\"model_name\\\": \\\"Qwen3-8B + LoRA (vanilla v4 seed=7)\\\", \\\"seed\\\": 42, \\\"checkpoint_source\\\": \\\"checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635\\\", \\\"eval_data\\\": \\\"47 ALFWorld tasks (clean, no injection)\\\", \\\"parent\\\": \\\"v4-vanilla-seed7\\\", \\\"gpu\\\": [\\\"cuda:1\\\"], \\\"pid\\\": \\\"160587\\\", \\\"log_path\\\": \\\"~/runs/tax_error_inject_agent/v4-vanilla-seed7-eval.log\\\", \\\"checkpoint_path\\\": \\\"eval_results/v4_vanilla_seed7_eval.json\\\", \\\"backend\\\": \\\"tmux\\\", \\\"account\\\": \\\"root\\\"}, \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_success_rate\\\": 0.745, \\\"eval_successes\\\": 35, \\\"eval_total\\\": 47, \\\"vs_seed42_pp\\\": 12.8}}}, \\\"count\\\": 30, \\\"total\\\": 66, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.267}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"v4-random-fixed-inject10-s7\": {\"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion — 最后一个 10% 训练。\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s7)\", \"seed\": 7}, \"metrics\": {\"final_loss\": 0.2352, \"train_loss_avg\": 0.4209, \"final_token_acc\": 0.9066, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3511.93, \"memory_gib\": 18.15, \"train_speed_s_per_it\": 2.148}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject10-s1-eval\": {\"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"198045\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s1-eval.log\", \"submitted_at\": \"2026-05-15T21:05:18.393Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s1)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"checkpoint_path\": \"checkpoints/v4_random_fixed_inject10_s1/v1-20260516-040130/checkpoint-1635\", \"wall_clock_seconds\": 1350.0, \"gpu_hours\": 0.37}, \"hypothesis\": \"v4 Random 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"metrics\": {\"success_rate\": 0.681, \"successes\": 32, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 10, \"success\": 5, \"rate\": 0.5}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 6, \"rate\": 0.857}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-s7-eval\": {\"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject10_s7/v1-20260516-040128/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"197555\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s7-eval.log\", \"submitted_at\": \"2026-05-15T21:02:21.785Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s7)\", \"seed\": 42, \"checkpoint_source\": \"v4-taxei-fixed-inject10-s7\", \"eval_data\": \"eval_tasks_47.json\", \"wall_clock_seconds\": 1522.4, \"gpu_hours\": 0.42}, \"hypothesis\": \"v4 TaxEI 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"metrics\": {\"success_rate\": 0.681, \"successes\": 32, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 7, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-s1-eval-r2\": {\"spec\": {\"parent\": \"v4-taxei-fixed-inject10-s1\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s1)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\"}, \"hypothesis\": \"v4 TaxEI 10% seed=1 eval (r2, dedicated GPU) — 47 ALFWorld clean tasks.\", \"metrics\": {\"success_rate\": 0.511, \"successes\": 24, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 4, \"rate\": 0.667}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-s7\": {\"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=7 (4,358 total). Dose-response 5-seed expansion.\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4_fixed_inject10.jsonl --seed 7\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"191997\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s7.log\", \"submitted_at\": \"2026-05-15T20:01:19.314Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"wall_clock_seconds\": 3683.3, \"gpu_hours\": 1.02}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.237, \"train_loss_avg\": 0.4212, \"final_token_acc\": 0.905, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3437, \"memory_gib\": 18.15, \"train_speed_s_per_it\": 2.102}}, \"v4-random-fixed-inject10-s1\": {\"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion.\", \"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_random_v4_fixed_inject10.jsonl --seed 1\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"192077\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s1.log\", \"submitted_at\": \"2026-05-15T20:01:21.468Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"wall_clock_seconds\": 3782.3, \"gpu_hours\": 1.05}, \"metrics\": {\"final_loss\": 0.3096, \"train_loss_avg\": 0.4238, \"final_token_acc\": 0.8902, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3488, \"memory_gib\": 18.13, \"train_speed_s_per_it\": 2.132}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-s123-eval-r3\": {\"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"194978\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123-eval-r3.log\", \"submitted_at\": \"2026-05-15T20:40:05.519Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s123\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s123\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (taxei fixed inject10 s123)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\", \"wall_clock_seconds\": 848.9, \"gpu_hours\": 0.24}, \"hypothesis\": \"v4 TaxEI 10% seed=123 eval (r3, dedicated GPU) — 47 ALFWorld clean tasks.\", \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject10-s0-eval-r3\": {\"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635 --num_episodes 47 --seed 42\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"195118\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0-eval-r3.log\", \"submitted_at\": \"2026-05-15T20:40:07.156Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10-s0\", \"checkpoint_source\": \"v4-random-fixed-inject10-s0\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random fixed inject10 s0)\", \"seed\": 42, \"data_path\": \"eval/eval_tasks_47.json\", \"wall_clock_seconds\": 745.0, \"gpu_hours\": 0.21}, \"hypothesis\": \"v4 Random 10% seed=0 eval (r3, dedicated GPU) — 47 ALFWorld clean tasks.\", \"metrics\": {\"success_rate\": 0.66, \"successes\": 31, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 4, \"total\": 8, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"success\": 7, \"total\": 11, \"rate\": 0.636}, \"pick_cool_then_place_in_recep\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"success\": 7, \"total\": 8, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"success\": 4, \"total\": 7, \"rate\": 0.571}}}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject10-s0-eval\": {\"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"188022\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0-eval.log\", \"submitted_at\": \"2026-05-15T18:57:43.056Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-random-fixed-inject10-s0\", \"checkpoint_source\": \"v4-random-fixed-inject10-s0\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"N/A\", \"model_name\": \"v4_random_fixed_inject10_s0\", \"seed\": 0, \"wall_clock_seconds\": 3975.6, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 Random 10% seed=0 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-taxei-fixed-inject10-s123-eval\": {\"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"187785\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123-eval.log\", \"submitted_at\": \"2026-05-15T18:57:40.646Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s123\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s123\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"N/A\", \"model_name\": \"v4_taxei_fixed_inject10_s123\", \"seed\": 123, \"wall_clock_seconds\": 3977.2, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 TaxEI 10% seed=123 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-taxei-fixed-inject10-s1-eval\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path /root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_fixed_inject10_s1_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"188906\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1-eval.log\", \"submitted_at\": \"2026-05-15T18:57:44.756Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s1\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s1\", \"eval_data\": \"eval_tasks_47.json\", \"data_count\": 47, \"data_path\": \"eval/eval_tasks_47.json\", \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"wall_clock_seconds\": 3927.9, \"gpu_hours\": 1.09}, \"hypothesis\": \"v4 TaxEI 10% seed=1 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"failed\", \"metrics\": {\"error\": \"CUDA OOM during model loading on GPU 0\"}}, \"v4-random-fixed-inject10-s123-eval\": {\"hypothesis\": \"v4 Random fixed-size 10% injection seed=123 eval — 47 ALFWorld tasks, dose-response 5-seed expansion\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s123/v0-20260516-015429/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_fixed_inject10_s123_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"v4-random-fixed-inject10-s123\", \"eval_data\": \"eval/eval_tasks_47.json\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123-eval.log\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 6, \"rate\": 0.75}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}}, \"v4-taxei-fixed-inject10-s0-eval\": {\"spec\": {\"command\": \"eval\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"188410\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s0-eval.log\", \"submitted_at\": \"2026-05-15T18:57:46.725Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"parent\": \"v4-taxei-fixed-inject10-s0\", \"checkpoint_source\": \"v4-taxei-fixed-inject10-s0\", \"eval_data\": \"valid_unseen\", \"data_count\": 47, \"data_path\": \"eval_results/v4_taxei_fixed_inject10_s0_eval.json\", \"model_name\": \"v4_taxei_fixed_inject10_s0\", \"seed\": 0, \"wall_clock_seconds\": 3970.2, \"gpu_hours\": 1.1}, \"hypothesis\": \"v4 TaxEI 10% seed=0 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\", \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.702, \"successes\": 33, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 8, \"rate\": 0.727}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 4, \"rate\": 0.571}}}}, \"v4-taxei-fixed-inject10-s1\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 1 --data_seed 1 --output_dir checkpoints/v4_taxei_fixed_inject10_s1 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"182703\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s1.log\", \"submitted_at\": \"2026-05-15T17:54:17.595Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s1/v0-20260516-015427/checkpoint-1635\", \"wall_clock_seconds\": 3728.4, \"gpu_hours\": 1.04}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=1 (4,358 total). Dose-response 5-seed expansion.\", \"metrics\": {\"final_loss\": 0.3013, \"train_loss_avg\": 0.4225, \"final_token_acc\": 0.8947, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3469, \"memory_gib\": 18.13, \"train_speed_s_per_it\": 2.121}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject10-s123\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --data_seed 123 --output_dir checkpoints/v4_random_fixed_inject10_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"182781\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s123.log\", \"submitted_at\": \"2026-05-15T17:54:20.028Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"wall_clock_seconds\": 3802.4, \"gpu_hours\": 1.06}, \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=123 (4,358 total). Dose-response 5-seed expansion.\", \"metrics\": {\"final_loss\": 0.3124, \"train_loss_avg\": 0.4236, \"final_token_acc\": 0.8867, \"total_steps\": 1635, \"epochs\": 3, \"train_runtime_sec\": 3535.7, \"train_samples_per_second\": 3.698, \"train_steps_per_second\": 0.462, \"memory_gib\": 18.95}, \"conclusion\": \"success\"}, \"v4-taxei-fixed-inject10-s123\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 123 --data_seed 123 --output_dir checkpoints/v4_taxei_fixed_inject10_s123 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"180877\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-fixed-inject10-s123.log\", \"submitted_at\": \"2026-05-15T17:48:23.907Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\", \"wall_clock_seconds\": 4085.3, \"gpu_hours\": 1.13}, \"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=123 (4,358 total = 3,922 clean + 436 injected). Dose-response 5-seed expansion — 补齐 10% 数据点。\", \"metrics\": {\"train_loss\": 0.4234, \"final_loss\": 0.3097, \"final_token_acc\": 0.8882, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3497, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s123/v0-20260516-014833/checkpoint-1635\"}, \"conclusion\": \"success\"}, \"v4-random-fixed-inject10-s0\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --data_seed 0 --output_dir checkpoints/v4_random_fixed_inject10_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"180956\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s0.log\", \"submitted_at\": \"2026-05-15T17:48:26.104Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_random_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\", \"wall_clock_seconds\": 4081.8, \"gpu_hours\": 1.13}, \"hypothesis\": \"v4 Random fixed-size ablation: 10% injection ratio seed=0 (4,358 total). Dose-response 5-seed expansion — 与 TaxEI 10% 对比 taxonomy 标签效果。\", \"metrics\": {\"train_loss\": 0.4227, \"final_loss\": 0.276, \"final_token_acc\": 0.9067, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3531, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_random_fixed_inject10_s0/v0-20260516-014835/checkpoint-1635\"}, \"conclusion\": \"success\"}, \"v4-training-dynamics-forward-v2\": {\"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/tax_error_inject_agent && CUDA_VISIBLE_DEVICES=2 bash scripts/run_training_dynamics_v2.sh\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"180322\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-training-dynamics-forward-v2.log\", \"submitted_at\": \"2026-05-15T16:56:31.040Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"training_dynamics\", \"data_count\": 0, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\", \"wall_clock_seconds\": 3546.9, \"gpu_hours\": 0.99}, \"conclusion\": \"success\", \"metrics\": {\"subsets_computed\": [\"vanilla_full\", \"taxei_full\", \"random_full\", \"taxei_inject10\", \"taxei_inject25\", \"taxei_inject50\"], \"taxei_inject50_injected_mean_loss\": 0.8185, \"taxei_inject50_clean_mean_loss\": 0.8514, \"per_operator\": {\"C1_ContextTruncation\": {\"mean\": 0.6489, \"n\": 101}, \"C4_ObservationMasking\": {\"mean\": 0.6782, \"n\": 92}, \"P1_StepOrderSwap\": {\"mean\": 0.6374, \"n\": 89}, \"P2_SubGoalDeletion\": {\"mean\": 0.6542, \"n\": 88}}, \"plots\": [\"subset_comparison\", \"operator_breakdown\", \"dose_response\"], \"output_dir\": \"/root/autodl-tmp/tax_error_inject_agent/artifacts/training_dynamics_v2/\"}}, \"v4-taxei-fixed-inject10-s0\": {\"hypothesis\": \"v4 TaxEI fixed-size ablation: 10% injection ratio seed=0 (4,358 total = 3,922 clean + 436 injected). Dose-response 5-seed expansion — 10% 是最薄弱环节，仅有 seed=42 一个数据点。\", \"spec\": {\"data_path\": \"data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl\", \"data_count\": 4358, \"model_name\": \"Qwen3-8B\", \"seed\": 0, \"injection_ratio\": 0.1, \"clean_count\": 3922, \"injected_count\": 436, \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/ablation_fixed/sft_taxei_v4_fixed_inject10.jsonl --lora_rank 16 --num_train_epochs 3 --seed 0 --data_seed 0 --output_dir checkpoints/v4_taxei_fixed_inject10_s0 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\\\"\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\", \"log_path\": \"checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/logging.jsonl\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.4238, \"final_loss\": 0.3102, \"final_token_acc\": 0.8822, \"epochs\": 3, \"total_steps\": 1635, \"train_runtime_sec\": 3494, \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/v4_taxei_fixed_inject10_s0/v0-20260516-005247/checkpoint-1635\"}}, \"v4-random-seed7-eval\": {\"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_seed7_eval.json\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"179098\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed7-eval.log\", \"submitted_at\": \"2026-05-15T17:29:24.122Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (random SFT seed=7)\", \"seed\": 42, \"checkpoint_source\": \"v4-random-seed7\", \"eval_data\": \"eval_tasks_47.json\", \"checkpoint_path\": \"/root/autodl-tmp/tax_error_inject_agent/checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427/checkpoint-3387\", \"wall_clock_seconds\": 852.6, \"gpu_hours\": 0.24}, \"hypothesis\": \"v4 Random SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion ← 基于 v4-random-seed7\", \"metrics\": {\"success_rate\": 0.553, \"successes\": 26, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 6, \"rate\": 0.545}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 5, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 3, \"rate\": 0.429}}}, \"conclusion\": \"success\"}, \"v4-random-seed1-eval\": {\"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/tax_error_inject_agent && mkdir -p eval_results && CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_random_seed1_eval.json\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"178005\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed1-eval.log\", \"submitted_at\": \"2026-05-15T17:18:03.664Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 872.9, \"gpu_hours\": 0.24}, \"metrics\": {\"success_rate\": 0.468, \"successes\": 22, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"success\": 5, \"total\": 6, \"rate\": 0.833}, \"pick_and_place_simple\": {\"success\": 2, \"total\": 8, \"rate\": 0.25}, \"pick_clean_then_place_in_recep\": {\"success\": 5, \"total\": 11, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"success\": 2, \"total\": 7, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"success\": 5, \"total\": 8, \"rate\": 0.625}, \"pick_two_obj_and_place\": {\"success\": 3, \"total\": 7, \"rate\": 0.429}}}, \"conclusion\": \"success\"}, \"v4-random-seed7\": {\"hypothesis\": \"v4 Random SFT seed=7 (5-seed expansion) — 9,029 samples, LoRA rank=16, 3 epochs\", \"spec\": {\"command\": \"swift sft --model /root/autodl-tmp/models/Qwen/Qwen3-8B --dataset data/mini_pipeline_v4/sft_random_v4.jsonl --lora_rank 16 --lora_alpha 32 --num_train_epochs 3 --seed 7 --output_dir checkpoints/mini_random_sft_v4_seed7 --gradient_accumulation_steps 8 --learning_rate 1e-4 --lr_scheduler_type cosine --gradient_checkpointing true --save_strategy epoch --logging_steps 5 --weight_decay 0.1 --adam_beta1 0.9 --adam_beta2 0.95\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_random_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"gpu\": \"cuda:1\", \"pid\": 164126, \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed7.log\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed7/v0-20260515-233427\"}, \"metrics\": {\"final_loss\": 0.173, \"final_token_acc\": 0.935, \"initial_loss\": 4.017, \"total_steps\": 3387, \"epochs\": 3, \"total_flos\": 697192362530058200, \"train_runtime_sec\": 6672, \"memory_gib\": 18.49}, \"conclusion\": \"success\"}, \"v4-random-seed1\": {\"spec\": {\"hypothesis\": \"v4 Random SFT seed=1 (5-seed expansion) — 9,029 samples, LoRA rank=16, 3 epochs\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 train/sft_train.py --config configs/mini_random_sft_v4_seed1.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_random_v4\", \"data_count\": 1129, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"gpu\": [\"cuda:0\"], \"pid\": \"163009\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-random-seed1.log\", \"checkpoint_path\": \"checkpoints/mini_random_sft_v4_seed1/v0-20260515-232340/\", \"submitted_at\": \"2026-05-15T15:23:31Z\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 6842.6, \"gpu_hours\": 1.9}, \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.167, \"final_token_acc\": 0.938, \"initial_loss\": 4.017, \"total_steps\": 3387, \"epochs\": 3, \"total_flos\": 697000000000000000}}, \"v4-taxei-seed1-eval\": {\"hypothesis\": \"v4 TaxEI SFT seed=1 eval — 47 ALFWorld tasks, 5-seed expansion\", \"spec\": {\"command\": \"python eval_agent.py --checkpoint checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387 --split valid_unseen\", \"server\": \"autodl-5090\", \"data_path\": \"valid_unseen\", \"data_count\": 47, \"model_name\": \"mini_taxei_sft_v4_seed1/checkpoint-3387\", \"seed\": 1, \"checkpoint_source\": \"v4-taxei-seed1\", \"eval_data\": \"valid_unseen\", \"gpu\": [\"cuda:2\"], \"pid\": 173824, \"log_path\": \"eval_results/v4_taxei_seed1_eval.json\", \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\", \"parent\": \"v4-taxei-seed1\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.596, \"successes\": 28, \"total\": 47, \"by_task_type\": {\"look_at_obj_in_light\": {\"total\": 6, \"success\": 5, \"rate\": 0.833}, \"pick_and_place_simple\": {\"total\": 8, \"success\": 4, \"rate\": 0.5}, \"pick_clean_then_place_in_recep\": {\"total\": 11, \"success\": 5, \"rate\": 0.455}, \"pick_cool_then_place_in_recep\": {\"total\": 7, \"success\": 2, \"rate\": 0.286}, \"pick_heat_then_place_in_recep\": {\"total\": 8, \"success\": 7, \"rate\": 0.875}, \"pick_two_obj_and_place\": {\"total\": 7, \"success\": 5, \"rate\": 0.714}}}}, \"v4-vanilla-seed1-eval\": {\"hypothesis\": \"v4 Vanilla SFT seed=1 eval — 47 ALFWorld tasks, 5-seed expansion\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_vanilla_seed1_eval.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=1)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4_seed1/v0-20260515-214031/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"gpu\": [\"cuda:0\"]}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.66, \"eval_successes\": 31, \"eval_total\": 47, \"vs_seed42_pp\": 4.3}}, \"v4-taxei-seed7-eval\": {\"hypothesis\": \"v4 TaxEI SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python3 eval/recovery.py --model_path checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --task_list eval/eval_tasks_47.json --num_episodes 47 --seed 42 --device cuda:0 --output eval_results/v4_taxei_seed7_eval.json\", \"server\": \"autodl-5090\", \"data_path\": \"eval/eval_tasks_47.json\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (TaxEI v4 seed=7)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_taxei_sft_v4_seed7/v0-20260515-214039/checkpoint-3387\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-taxei-seed7\", \"gpu\": [\"cuda:3\"], \"pid\": \"165338\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-taxei-seed7-eval.log\", \"checkpoint_path\": \"eval_results/v4_taxei_seed7_eval.json\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"success_rate\": 0.617, \"successes\": 29, \"total\": 47, \"by_task\": {\"look_at_obj_in_light\": \"4/6 (0.667)\", \"pick_and_place_simple\": \"5/8 (0.625)\", \"pick_clean_then_place_in_recep\": \"5/11 (0.455)\", \"pick_cool_then_place_in_recep\": \"4/7 (0.571)\", \"pick_heat_then_place_in_recep\": \"7/8 (0.875)\", \"pick_two_obj_and_place\": \"4/7 (0.571)\"}}}, \"v4-training-dynamics-forward\": {\"hypothesis\": \"D027 Training Dynamics: Post-hoc forward pass on seed=42 checkpoints (Vanilla/TaxEI/Random + dose-response 10%/25%/50%) — compute per-subset loss (clean vs injected) and per-operator loss (P1/P2/C1/C4). Key finding: training loss SD=0.0004 across seeds but eval SD=8.6pp — memorization-generalization dissociation.\", \"spec\": {\"command\": \"bash scripts/run_training_dynamics.sh\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/tax_error_inject_agent/data/mini_pipeline_v4/\", \"data_count\": 6, \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"metrics\": {\"vanilla_full\": {\"clean_loss\": 0.6853, \"clean_n\": 4358}, \"taxei_full\": {\"clean_loss\": 0.7712, \"injected_loss\": 0.6139, \"clean_n\": 8269, \"injected_n\": 760, \"per_operator\": {\"P1_StepOrderSwap\": 0.6165, \"P2_SubGoalDeletion\": 0.6161, \"C1_ContextTruncation\": 0.5932, \"C4_ObservationMasking\": 0.6298}}, \"random_full\": {\"clean_loss\": 0.7354, \"injected_loss\": 0.5902, \"clean_n\": 8269, \"injected_n\": 760}, \"dose_response\": {\"taxei_10pct\": {\"clean_loss\": 0.6628, \"injected_loss\": 0.6464, \"gap\": -0.0164, \"injected_n\": 70}, \"taxei_25pct\": {\"clean_loss\": 0.701, \"injected_loss\": 0.574, \"gap\": -0.127, \"injected_n\": 168}, \"taxei_50pct\": {\"clean_loss\": 0.8516, \"injected_loss\": 0.6547, \"gap\": -0.1969, \"injected_n\": 370}}, \"key_findings\": \"Clear dose-response: injected-clean gap widens from -0.016 (10%) to -0.127 (25%) to -0.197 (50%). TaxEI operators C1_ContextTruncation consistently lowest loss. Higher injection rates also degrade clean sample loss (0.663→0.701→0.852).\"}, \"conclusion\": \"success\"}, \"v4-taxei-seed1\": {\"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 1 --lora_rank 16 --lora_alpha 32 --num_train_epochs 3\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 1, \"gpu\": \"cuda:2\", \"pid\": 154937}, \"metrics\": {\"final_loss\": 0.1667, \"avg_loss\": 0.3561, \"token_accuracy\": 0.915, \"final_token_acc\": 0.942, \"train_steps\": 3387, \"train_epochs\": 3, \"train_duration_min\": 108.9, \"memory_gib\": 18.49, \"checkpoint_path\": \"checkpoints/mini_taxei_sft_v4_seed1/v0-20260515-214035/checkpoint-3387\"}, \"conclusion\": \"success\"}, \"v4-taxei-seed7\": {\"spec\": {\"command\": \"swift sft --model Qwen3-8B --dataset sft_taxei_v4.jsonl --seed 7 --lora_rank 16 --lora_alpha 32 --3epochs\", \"server\": \"autodl-5090\", \"data_path\": \"data/mini_pipeline_v4/sft_taxei_v4.jsonl\", \"data_count\": 9029, \"model_name\": \"Qwen3-8B\", \"seed\": 7, \"gpu\": \"cuda:3\", \"pid\": 155145}, \"metrics\": {\"current_step\": 3387, \"total_steps\": 3387, \"progress_pct\": 100, \"train_loss\": 0.3568, \"final_step_loss\": 0.1753, \"token_acc\": 0.9009, \"final_token_acc\": 0.9328, \"train_runtime_s\": 6591.9, \"epochs\": 3, \"peak_memory_gib\": 18.49, \"gpu\": \"cuda:3\", \"pid\": 155145}, \"conclusion\": \"success\"}, \"v4-vanilla-seed7-eval\": {\"hypothesis\": \"v4 Vanilla SFT seed=7 eval — 47 ALFWorld tasks, 5-seed expansion\", \"spec\": {\"command\": \"python3 eval/recovery.py --model_path checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635 --base_model /root/autodl-tmp/models/Qwen/Qwen3-8B --no_inject --num_episodes 47 --output eval_results/v4_vanilla_seed7_eval.json --device cuda:1 --seed 42\", \"server\": \"autodl-5090\", \"data_path\": \"eval/47 ALFWorld valid_unseen\", \"data_count\": 47, \"model_name\": \"Qwen3-8B + LoRA (vanilla v4 seed=7)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/mini_vanilla_sft_v4_seed7/v1-20260515-214032/checkpoint-1635\", \"eval_data\": \"47 ALFWorld tasks (clean, no injection)\", \"parent\": \"v4-vanilla-seed7\", \"gpu\": [\"cuda:1\"], \"pid\": \"160587\", \"log_path\": \"~/runs/tax_error_inject_agent/v4-vanilla-seed7-eval.log\", \"checkpoint_path\": \"eval_results/v4_vanilla_seed7_eval.json\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_success_rate\": 0.745, \"eval_successes\": 35, \"eval_total\": 47, \"vs_seed42_pp\": 12.8}}}, \"count\": 30, \"total\": 66, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.267}}"
    }
  },
  "sourceToolAssistantUUID": "b4dedea6-c2e8-4788-a3d2-994037e3272a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 39 · 2026-05-15T22:13:46.379Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__list_workers · `toolu_01Qf2VVB6kG6wbA9jaJnKTyq`</summary>

```json
{
  "project": "tax_error_inject_agent",
  "status": "running"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5a0af7a1-1a87-4f20-bea8-827ac47089bb",
  "isSidechain": false,
  "requestId": "req_011Cb589TcCAVgDV9UnQhv3Y",
  "type": "assistant",
  "uuid": "4f0c15d8-dfe5-4243-9062-2165f5aa11c1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XXqsNUUDeqG6Dg8debGCeB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2549,
      "cache_read_input_tokens": 41698,
      "output_tokens": 340,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2549,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 340,
          "cache_read_input_tokens": 41698,
          "cache_creation_input_tokens": 2549,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2549
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

_source line 40 · 2026-05-15T22:13:46.408Z_

<details><summary>↩ Tool result · `toolu_01Qf2VVB6kG6wbA9jaJnKTyq`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"workers\": [], \"count\": 0}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4f0c15d8-dfe5-4243-9062-2165f5aa11c1",
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "2ee62f45-fe19-4b56-a17c-e039c2ed3301",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"workers\\\": [], \\\"count\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"workers\": [], \"count\": 0}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "4f0c15d8-dfe5-4243-9062-2165f5aa11c1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 41_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[CRON] 实验进程已正常退出，状态已转为 ANALYZING，需要你分析结果并推进到 DONE。 详情: Process exited cleanly, W&B data available  - exp_id: v4-random-fixed-inject10-s7-eval - project: tax_error_inject_agent - server: autodl-5090 -…",
  "leafUuid": "2ee62f45-fe19-4b56-a17c-e039c2ed3301",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e"
}
```

---

### Runtime record

_source line 42_

```json
{
  "type": "ai-title",
  "aiTitle": "Analyze experiment results and complete workflow",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e"
}
```

---

### Assistant

_source line 43 · 2026-05-15T22:14:05.903Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have comprehensive context. Let me compile the 10% fixed-size injection eval results:

**TaxEI 10% (fixed-size) eval results across 5 seeds:**
- seed=0 (v4-taxei-fixed-inject10-s0-eval): 70.2% (33/47)
- seed=42: Need to check - this should be from the original experiment
- seed=123 (v4-taxei-fixed-inject10-s123-eval-r3): 55.3% (26/47)


- seed=1 (v4-taxei-fixed-inject10-s1-eval-r2): 51.1% (24/47)
- seed=7 (v4-taxei-fixed-inject10-s7-eval): 68.1% (32/47)

Now looking at the Random 10% fixed-size results, which show similar performance patterns across the seeds I've collected so far, though I still need to track down the seed=42 and seed=123 entries for the random baseline.

The seed=7 random experiment is currently in an analyzing state without metrics yet, so I need to spawn a worker to SSH into the server and pull the log files to extract those results. Let me prioritize getting those metrics first before comparing the full injection versus random injection performance.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2ee62f45-fe19-4b56-a17c-e039c2ed3301",
  "isSidechain": false,
  "requestId": "req_011Cb58ACHEASWBLPYgGXSf8",
  "type": "assistant",
  "uuid": "548da75b-9cf7-460a-9dd1-3e2bdf3da822",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EwTeTKz6ePTFSFx2castsR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17121,
      "cache_read_input_tokens": 44247,
      "output_tokens": 1596,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17121,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1596,
          "cache_read_input_tokens": 44247,
          "cache_creation_input_tokens": 17121,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17121
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

_source line 44 · 2026-05-15T22:14:06.012Z_

Worker 池=0，立即派 Worker 分析实验日志。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "548da75b-9cf7-460a-9dd1-3e2bdf3da822",
  "isSidechain": false,
  "requestId": "req_011Cb58ACHEASWBLPYgGXSf8",
  "type": "assistant",
  "uuid": "832d1359-6652-43df-a516-c8c4286471b3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EwTeTKz6ePTFSFx2castsR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17121,
      "cache_read_input_tokens": 44247,
      "output_tokens": 1596,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17121,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1596,
          "cache_read_input_tokens": 44247,
          "cache_creation_input_tokens": 17121,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17121
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

_source line 45 · 2026-05-15T22:14:21.421Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__spawn_worker · `toolu_01PUcYG3MoEP7kFDpSejW2nY`</summary>

````json
{
  "task_type": "analysis:v4-random-fixed-inject10-s7-eval",
  "project": "tax_error_inject_agent",
  "task_prompt": "## 任务\n分析已完成的 eval 实验 `v4-random-fixed-inject10-s7-eval` 的结果。\n\n## 实验信息\n- exp_id: v4-random-fixed-inject10-s7-eval\n- server: autodl-5090\n- log_path: ~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s7-eval.log\n- command: python3 eval/recovery.py --model_path checkpoints/v4_random_fixed_inject10_s7/v1-20260516-045440/checkpoint-1635 --num_episodes 47 --seed 42\n- hypothesis: v4 Random 10% seed=7 eval — 47 ALFWorld clean tasks. Dose-response 5-seed expansion.\n\n## 具体步骤\n\n1. SSH 到 autodl-5090，读取日志文件:\n   ```\n   tail -100 ~/runs/tax_error_inject_agent/v4-random-fixed-inject10-s7-eval.log\n   ```\n\n2. 查看 eval 结果 JSON（如果存在）:\n   ```\n   ls -la /root/autodl-tmp/tax_error_inject_agent/eval_results/*random*inject10*s7* 2>/dev/null\n   cat /root/autodl-tmp/tax_error_inject_agent/eval_results/*random*inject10*s7*.json 2>/dev/null | python3 -m json.tool\n   ```\n\n3. 从日志中提取:\n   - 总 success rate（successes / total）\n   - 每个 task type 的 success/total/rate\n   - 是否有错误或异常\n   - wall clock time\n\n4. 用 `update_registry` 更新实验:\n   - field=\"metrics\", value= 包含 success_rate, successes, total, by_task_type 的 dict\n   - field=\"conclusion\", value=\"success\" (如果正常完成) 或 \"failed\"/\"negative\"\n   - field=\"status\", value=\"DONE\"\n   - spec 补充: checkpoint_path, wall_clock_seconds, gpu_hours\n\n5. 如果有 eval 结果 JSON，也检查是否已保存到 eval_results/ 目录。\n\n## 对比参考（同系列已完成的 10% fixed eval）\n- TaxEI 10% s0: 70.2% (33/47)\n- TaxEI 10% s123: 55.3% (26/47)\n- TaxEI 10% s1: 51.1% (24/47)\n- TaxEI 10% s7: 68.1% (32/47)\n- Random 10% s0: 66.0% (31/47)\n- Random 10% s123: 55.3% (26/47)\n- Random 10% s1: 68.1% (32/47)\n- Random 10% s7: ← 这是我们要分析的\n\n## 输出\n在 update_registry 完成后，输出一段简短总结：\n- success_rate 和 per-task breakdown\n- 与同系列其他 seed 的对比\n- 现在 Random 10% 的 5-seed mean±SD（如果这是最后一个 seed）\n",
  "tool_groups": [
    "ssh",
    "registry"
  ]
}
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "832d1359-6652-43df-a516-c8c4286471b3",
  "isSidechain": false,
  "requestId": "req_011Cb58ACHEASWBLPYgGXSf8",
  "type": "assistant",
  "uuid": "90012839-1751-477d-a480-6c87e6960c73",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EwTeTKz6ePTFSFx2castsR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 17121,
      "cache_read_input_tokens": 44247,
      "output_tokens": 1596,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17121,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1596,
          "cache_read_input_tokens": 44247,
          "cache_creation_input_tokens": 17121,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17121
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

_source line 46 · 2026-05-15T22:14:24.095Z_

<details><summary>↩ Tool result · `toolu_01PUcYG3MoEP7kFDpSejW2nY`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"worker_id\": \"worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421\", \"status\": \"running\", \"log_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/logs/workers/worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421.log\", \"setup_data\": {}, \"message\": \"Worker worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421 started. Use get_worker_status('worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421') to check progress.\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "90012839-1751-477d-a480-6c87e6960c73",
  "isSidechain": false,
  "promptId": "c7bdc458-102c-4328-bfb4-540992633019",
  "type": "user",
  "uuid": "1818a094-a64d-4731-b537-8eadfaee01f7",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"worker_id\\\": \\\"worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421\\\", \\\"status\\\": \\\"running\\\", \\\"log_path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/logs/workers/worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421.log\\\", \\\"setup_data\\\": {}, \\\"message\\\": \\\"Worker worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421 started. Use get_worker_status('worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421') to check progress.\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"worker_id\": \"worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421\", \"status\": \"running\", \"log_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/logs/workers/worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421.log\", \"setup_data\": {}, \"message\": \"Worker worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421 started. Use get_worker_status('worker_analysis_v4-random-fixed-inject10-s7-eval_20260515T221421') to check progress.\"}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "90012839-1751-477d-a480-6c87e6960c73",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/tax_error_inject_agent/.claude/sessions/agent_3327eadd",
  "sessionId": "317bd1cf-f718-48d3-9b82-4f5aa233ca0e",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---
