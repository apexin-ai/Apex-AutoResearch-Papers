# Research conversation: [CRON] 实验进程异常退出（失败），需要你诊断原因。 详情: Process exited without valid W&B metrics - exp_id: exp-069-llama8b-logiqa200 - project:

**Beyond Self-Consistency: Self-Extracted Constraints Reduce to Majority Voting under Zero-Shot Extraction (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 40
- **Recorded user turns:** 1
- **Tool calls:** 10
- **Original source:** `logs/chats/exported-trajectories/account-2/e0fe2496-1882-439a-bfe8-1bec5fa0e327.jsonl`
- **Structured JSON:** [`4d9e67712b11e6f67cfd.json`](../../sessions/4d/4d9e67712b11e6f67cfd.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-19T14:32:13.639Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-19T14:32:13.639Z",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "content": "[CRON] 实验进程异常退出（失败），需要你诊断原因。\n详情: Process exited without valid W&B metrics\n\n- exp_id: exp-069-llama8b-logiqa200\n- project: symb_invariant_consensus\n- server: westd-16639"
}
```

---

### Runtime record

_source line 2 · 2026-05-19T14:32:13.642Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-19T14:32:13.642Z",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327"
}
```

---

## Round 1

38 recorded events

### User

_source line 3 · 2026-05-19T14:32:13.674Z_

[CRON] 实验进程异常退出（失败），需要你诊断原因。
详情: Process exited without valid W&B metrics

- exp_id: exp-069-llama8b-logiqa200
- project: symb_invariant_consensus
- server: westd-16639

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "62ab6029-0ec6-4d33-8f75-d725e1fbd51a",
  "type": "user",
  "uuid": "8878377c-c0cc-4b00-ad3f-3f7c6f44c4d0",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-19T14:32:13.673Z_

```json
{
  "parentUuid": "8878377c-c0cc-4b00-ad3f-3f7c6f44c4d0",
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
  "uuid": "71856faf-8c7b-408c-a5e0-94fcbde7b4c3",
  "timestamp": "2026-05-19T14:32:13.673Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-19T14:32:13.673Z_

```json
{
  "parentUuid": "71856faf-8c7b-408c-a5e0-94fcbde7b4c3",
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
  "uuid": "094416cd-8af7-470d-98f1-36e55ab91064",
  "timestamp": "2026-05-19T14:32:13.673Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-19T14:32:13.673Z_

```json
{
  "parentUuid": "094416cd-8af7-470d-98f1-36e55ab91064",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "7b19d29b-8c59-4de0-94d8-a71121403555",
  "timestamp": "2026-05-19T14:32:13.673Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
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
  "aiTitle": "Diagnose W&B metrics missing from experiment exit",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327"
}
```

---

### Assistant

_source line 8 · 2026-05-19T14:32:18.932Z_

<details><summary>Logged reasoning block</summary>

```text
实验失败回调到达。我需要按 session-start 先初始化，然后按 on-experiment-failed skill 处理这个失败的实验。

让我先执行 session-start 初始化步骤，然后读取 on-experiment-failed skill。
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7b19d29b-8c59-4de0-94d8-a71121403555",
  "isSidechain": false,
  "requestId": "req_011CbC6CFyphoqN9tveLDE2o",
  "type": "assistant",
  "uuid": "23d675e7-4960-4896-8dc2-e64809928929",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0123UPFjZY7PjFso1NAJeRan",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25072,
      "cache_read_input_tokens": 11841,
      "output_tokens": 319,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25072,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 319,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 25072,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25072
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

_source line 9 · 2026-05-19T14:32:19.490Z_

收到实验失败回调，开始处理。先执行 session-start 初始化。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "23d675e7-4960-4896-8dc2-e64809928929",
  "isSidechain": false,
  "requestId": "req_011CbC6CFyphoqN9tveLDE2o",
  "type": "assistant",
  "uuid": "dc259386-581c-4e3b-8fa0-b8fcb6319017",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0123UPFjZY7PjFso1NAJeRan",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25072,
      "cache_read_input_tokens": 11841,
      "output_tokens": 319,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25072,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 319,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 25072,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25072
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

_source line 10 · 2026-05-19T14:32:21.849Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01Vt5FjTLFgGQLAtnGe4SegH`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__reconcile_crons,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_roadmap,mcp__agent-ml-research__main_agent_post_to_director,mcp__agent-ml-research__update_registry,mcp__agent-ml-research__spawn_worker,mcp__agent-ml-research__list_workers,mcp__agent-ml-research__get_worker_status",
  "max_results": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dc259386-581c-4e3b-8fa0-b8fcb6319017",
  "isSidechain": false,
  "requestId": "req_011CbC6CFyphoqN9tveLDE2o",
  "type": "assistant",
  "uuid": "34f75714-238b-48ac-a495-fce8cc83849b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0123UPFjZY7PjFso1NAJeRan",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 25072,
      "cache_read_input_tokens": 11841,
      "output_tokens": 319,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 25072,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 319,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 25072,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 25072
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

_source line 11 · 2026-05-19T14:32:21.856Z_

<details><summary>↩ Tool result · `toolu_01Vt5FjTLFgGQLAtnGe4SegH`</summary>

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

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__main_agent_post_to_director"
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
  "tool_name": "mcp__agent-ml-research__spawn_worker"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__list_workers"
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
  "parentUuid": "34f75714-238b-48ac-a495-fce8cc83849b",
  "isSidechain": false,
  "promptId": "62ab6029-0ec6-4d33-8f75-d725e1fbd51a",
  "type": "user",
  "uuid": "90742ded-0f00-41b7-9b8f-2b8afdc121f8",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__reconcile_crons",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__main_agent_post_to_director",
      "mcp__agent-ml-research__update_registry",
      "mcp__agent-ml-research__spawn_worker",
      "mcp__agent-ml-research__list_workers",
      "mcp__agent-ml-research__get_worker_status"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__reconcile_crons,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_roadmap,mcp__agent-ml-research__main_agent_post_to_director,mcp__agent-ml-research__update_registry,mcp__agent-ml-research__spawn_worker,mcp__agent-ml-research__list_workers,mcp__agent-ml-research__get_worker_status",
    "total_deferred_tools": 82
  },
  "sourceToolAssistantUUID": "34f75714-238b-48ac-a495-fce8cc83849b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-19T14:32:25.023Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01EPRK3mvvBUQgnPAGT1udh4`</summary>

```json
{
  "project": "symb_invariant_consensus",
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
  "parentUuid": "90742ded-0f00-41b7-9b8f-2b8afdc121f8",
  "isSidechain": false,
  "requestId": "req_011CbC6CrsnyrKucF8fHUQq1",
  "type": "assistant",
  "uuid": "4e35c5d5-69d9-483d-8993-5931f9bb2852",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01APmHu3mWPmedC4d4pFzQTk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 3529,
      "cache_read_input_tokens": 36913,
      "output_tokens": 259,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3529,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 259,
          "cache_read_input_tokens": 36913,
          "cache_creation_input_tokens": 3529,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3529
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

_source line 13 · 2026-05-19T14:32:25.505Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__reconcile_crons · `toolu_011MvopQRPRbn9JDKcJL63oc`</summary>

```json
{}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4e35c5d5-69d9-483d-8993-5931f9bb2852",
  "isSidechain": false,
  "requestId": "req_011CbC6CrsnyrKucF8fHUQq1",
  "type": "assistant",
  "uuid": "b040030f-c815-4a0e-8f2a-566a5a9d5c29",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01APmHu3mWPmedC4d4pFzQTk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 3529,
      "cache_read_input_tokens": 36913,
      "output_tokens": 259,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3529,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 259,
          "cache_read_input_tokens": 36913,
          "cache_creation_input_tokens": 3529,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3529
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

_source line 14 · 2026-05-19T14:32:25.677Z_

<details><summary>↩ Tool result · `toolu_01EPRK3mvvBUQgnPAGT1udh4`</summary>

```text
Error: result (175,796 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus--claude-sessions-agent-6d4dc7e1/e0fe2496-1882-439a-bfe8-1bec5fa0e327/tool-results/mcp-agent-ml-research-read_registry-1779201145663.txt.
Format: JSON with schema: {result: string}
Use offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.
REQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:
- You MUST read the content from the file at /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus--claude-sessions-agent-6d4dc7e1/e0fe2496-1882-439a-bfe8-1bec5fa0e327/tool-results/mcp-agent-ml-research-read_registry-1779201145663.txt in sequential chunks until 100% of the content has been read.
- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.
- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4e35c5d5-69d9-483d-8993-5931f9bb2852",
  "isSidechain": false,
  "promptId": "62ab6029-0ec6-4d33-8f75-d725e1fbd51a",
  "type": "user",
  "uuid": "765365e4-f4cc-4b57-b8e1-681343d67b94",
  "toolUseResult": "Error: result (175,796 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus--claude-sessions-agent-6d4dc7e1/e0fe2496-1882-439a-bfe8-1bec5fa0e327/tool-results/mcp-agent-ml-research-read_registry-1779201145663.txt.\nFormat: JSON with schema: {result: string}\nUse offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.\nREQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:\n- You MUST read the content from the file at /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus--claude-sessions-agent-6d4dc7e1/e0fe2496-1882-439a-bfe8-1bec5fa0e327/tool-results/mcp-agent-ml-research-read_registry-1779201145663.txt in sequential chunks until 100% of the content has been read.\n- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.\n- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***\n",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"exp-069-llama8b-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:40:15.817Z\", \"updated_at\": \"2026-05-19T14:32:06.439Z\", \"hypothesis\": \"LLaMA-3.1-8B-Instruct 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 LLaMA-8B SC=66.18% delta=-4.41pp (exp-063, negative/error amplification)。LogiQA 上 Mistral-7B SC=51% delta=+0.5pp (exp-049b)，Qwen2.5-14B SC=78.5% delta=-0.50pp (exp-038)。测试 LLaMA-8B 在 LogiQA 上的 regime（SC 预计 50-60%，可能在 error amplification zone）。parent=exp-063-llama8b-folio204-16639\", \"parent\": \"exp-063-llama8b-folio204-16639\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8012/v1 --model auto --seed 42 --strategyqa-data data/logiqa_200.json --folio-data data/empty.json --math-data data/empty.json --pw-data data/empty.json --output results/exp069_llama8b_logiqa200/exp069_results.json --save-intermediates\", \"server\": \"westd-16639\", \"gpu\": \"cuda:2\", \"port\": 8012, \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42}, \"notes\": \"诊断 2026-05-19T20:17: westd-16639 上运行正常。tmux_session=exp-069-llama8b-logiqa200, vLLM via nohup (非 tmux), run PID=152414, vLLM PID=151829 (EngineCore on GPU2). port=8012, CUDA_VISIBLE_DEVICES=2. 进度: 12/200 (6%), 刚启动约12分钟。GPU2 利用率 96%, 显存 88254/97887 MiB。vLLM model=/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct, max-model-len=8192。同机其他实验: exp-048(GPU3,457/600), exp-064(GPU0,74/204), exp-068(GPU1,121/200)。\", \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"failed\", \"completed_at\": \"\", \"reproduce\": {\"finished_at\": \"2026-05-19T14:32:03.443Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T14:32:09.270208+00:00\"}]}}, \"exp-069-mistral-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:50:28.223Z\", \"updated_at\": \"2026-05-19T14:19:37.076Z\", \"hypothesis\": \"Mistral-7B-Instruct-v0.3 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 Mistral 是唯一 Goldilocks 候选 (SC≈55%, Δ=+4.90pp seed=42)。如果 LogiQA SC 也在 55-65% 且 Δ>0，则跨数据集验证 Goldilocks zone 存在。parent=exp-033\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python -u run_logiqa.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8001/v1 --model auto --data data/logiqa_200.json --output results/exp069_mistral_logiqa200/exp069_results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"gpu\": \"cuda:1\", \"port\": 8001, \"tmux_session\": \"exp-069-mistral-logiqa200\", \"vllm_session\": \"exp069_vllm\", \"log_path\": \"/root/symb_invariant_consensus/results/exp069_mistral_logiqa200/exp069_results.json\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp069_mistral_logiqa200/\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T13:12:53.430Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T13:12:56.873986+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.495, \"sica_accuracy\": 0.465, \"delta\": -0.03, \"n_samples\": 200}, \"completed_at\": \"2026-05-19T13:56:33.286Z\", \"notes\": \"与 exp-049b 结果不一致调查：5/7 SICA 核心模块代码版本不同（md5 全部不匹配）。关键差异：scorer.py tie-breaking（049b: max() 随机 vs 069: sorted() 字母序）、constraint_extractor/z3_maxsat/pipeline 均有变化。049b 还设了 VLLM_USE_FLASHINFER_SAMPLER=0。prompt 模板相同。两组数据不可直接比较。exp-069 使用 westd-25068 上的最新代码版本。\"}, \"exp-070-qwen7b-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:40:18.453Z\", \"updated_at\": \"2026-05-19T14:18:52.579Z\", \"hypothesis\": \"Qwen2.5-7B-Instruct 在 LogiQA-200 上 SICA vs SC。FOLIO 上 SC=75.98% (Type A confirmation bias, Δ=+0.49pp)。LogiQA 可能更难，SC 可能降到 55-65% 进入 Goldilocks zone，或保持 >75% 继续 Type A。验证 regime 跨数据集一致性。parent=exp-061\", \"parent\": \"exp-061\", \"spec\": {\"command\": \"python -u run_logiqa.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8002/v1 --model auto --data data/logiqa_200.json --output results/exp070_qwen7b_logiqa200/exp070_results.json --save-intermediates\", \"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"pid\": \"213756\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-070-qwen7b-logiqa200.log\", \"submitted_at\": \"2026-05-19T11:56:05.650Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"port\": 8002, \"tmux_session\": \"exp-070-qwen7b-logiqa200\", \"vllm_session\": \"exp070_vllm\", \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-7B-Instruct\", \"eval_data\": \"data/logiqa_200.json\", \"wall_clock_seconds\": 3630.6, \"gpu_hours\": 1.01}, \"reproduce\": {\"finished_at\": \"2026-05-19T12:56:34.965Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T12:56:36.273Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T12:56:40.490804+00:00\"}]}, \"metrics\": {\"sc_accuracy\": 0.685, \"sica_accuracy\": 0.71, \"delta\": 0.025, \"n_samples\": 200, \"sc_correct\": 137, \"sica_correct\": 142, \"discordant_b\": 1, \"discordant_c\": 6, \"mcnemar_chi2\": 2.2857, \"mcnemar_p\": 0.131, \"mcnemar_p_exact\": 0.125, \"significant_005\": false, \"cohens_kappa\": 0.917, \"kappa_interpretation\": \"almost_perfect\"}, \"notes\": \"Reviewer 独立验证（从 exp070_results.json 确认）：SC=137/200=68.5%, SICA=142/200=71.0%, Δ=+2.5pp。原 diagnostic worker 读取了错误数据源，误报 SC=SICA=79.5%（差距 11pp/22题）。已由 Director 指令修正。\"}, \"exp-053-mistral-folio204-seed456\": {\"status\": \"QUEUED\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:17:36.430Z\", \"updated_at\": \"2026-05-19T13:59:23.212Z\", \"hypothesis\": \"exp-033 replication (seed=456): Mistral-7B FOLIO-204 K=12 T=0.7，第二组独立 replication。与 exp-052 (seed=123) 一起验证 exp-033 结论 robustness。parent=exp-033\", \"conclusion\": \"killed\", \"notes\": \"Stale duplicate. 实际实验已在 exp-053 (短 ID) 下完成 (DONE)。本条目是重复创建的长名称版本，清理。\"}, \"exp-052-mistral-folio204-seed123\": {\"status\": \"QUEUED\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:17:34.705Z\", \"updated_at\": \"2026-05-19T13:59:22.541Z\", \"hypothesis\": \"exp-033 replication (seed=123): Mistral-7B FOLIO-204 K=12 T=0.7，与 exp-033 (seed=42, delta=+4.90pp, p=0.013) 完全相同配置，仅 seed 不同。验证正向结果是否 seed-robust。parent=exp-033\", \"conclusion\": \"killed\", \"notes\": \"Stale duplicate. 实际实验已在 exp-052 (短 ID) 下完成 (DONE)。本条目是重复创建的长名称版本，清理。\"}, \"exp-068-qwen3-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:13:19.371Z\", \"updated_at\": \"2026-05-19T13:53:10.914Z\", \"hypothesis\": \"Qwen3-14B non-thinking 在 LogiQA-200 上 SICA vs SC。FOLIO SC=84.80%, PW SC=85.0%，LogiQA 预计也在 confirmation bias zone。验证跨数据集 Type A 一致性。parent=exp-040\", \"parent\": \"exp-040\", \"spec\": {\"log_path\": \"/root/symb_invariant_consensus/results/exp068_qwen3_logiqa200/exp068.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp068_qwen3_logiqa200/exp068_results.json\"}, \"notes\": \"Reviewer 独立验证：输出文件完整，200/200 样本已处理。SC=SICA=0.81，null effect。原被 CRON 错误标记为 failed（无 W&B 数据时默认标 failed）。\", \"reproduce\": {\"finished_at\": \"2026-05-19T13:07:59.122Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T13:08:00.470Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T13:08:03.397783+00:00\"}]}, \"metrics\": {\"sc_accuracy\": 0.81, \"sica_accuracy\": 0.81, \"delta\": 0, \"n_samples\": 200}}, \"exp-064-deepseek-r1-qwen3-8b-folio204\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:49:07.235Z\", \"updated_at\": \"2026-05-19T13:09:54.480Z\", \"hypothesis\": \"DeepSeek-R1-0528-Qwen3-8B (reasoning distill) 在 FOLIO-204 上 SICA vs SC。测试 reasoning 模型在 8B scale 是否出现 degenerate regime (C₀<5%) 或因 8B 能力较弱落入 error amplification / Goldilocks zone。\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 8192 --folio-data data/folio_full.json --seed 42\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"DeepSeek-R1-0528-Qwen3-8B\", \"seed\": 42, \"gpu\": \"cuda:0\", \"port\": 8002, \"checkpoint_source\": \"DeepSeek-R1-0528-Qwen3-8B (HuggingFace)\", \"eval_data\": \"data/folio_full.json\", \"notes\": \"Retry of exp-064 (killed on cuda:2). Worker relaunched on cuda:0 with tokenizer fix. Progress ~77/204 as of 12:20 UTC.\"}, \"failure_reason\": \"\", \"conclusion\": \"\", \"completed_at\": \"\"}, \"exp-064\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T08:56:53.587Z\", \"updated_at\": \"2026-05-19T12:13:57.742Z\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 8192 --folio-data data/folio_full.json --seed 42\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"DeepSeek-R1-0528-Qwen3-8B\", \"seed\": 42, \"gpu\": \"cuda:2 (RTX PRO 6000 Blackwell)\", \"port\": 8002, \"notes\": \"Fixed tokenizer: LlamaTokenizerFast->PreTrainedTokenizerFast. VLLM_USE_FLASHINFER_SAMPLER=0 for Blackwell.\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T12:13:57.742Z\"}, \"exp-067-mistral-folio-seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T09:14:16.096Z\", \"updated_at\": \"2026-05-19T12:10:24.878Z\", \"hypothesis\": \"Mistral-7B FOLIO seed=789 第4 seed replication。已有 s42 +3.43pp, s123 +2.94pp, s456 0.00pp。增加统计样本验证 seed variance 和 SC-Δ 相关性。parent=exp-033\", \"parent\": \"exp-033\", \"spec\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"data_count\": 204, \"seed\": 789, \"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 789 --api-base http://localhost:8012/v1 --model auto --folio-data data/folio_full.json --math-data data/empty.json --pw-data data/empty.json --output results/exp067_mistral_folio_seed789/exp067_results.json\", \"data_path\": \"data/folio_full.json\", \"checkpoint_source\": \"/root/autodl-tmp/models/Mistral-7B-Instruct-v0.3\", \"eval_data\": \"data/folio_full.json\", \"log_path\": \"results/exp067_mistral_folio_seed789/\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T11:21:00.412Z\", \"metrics\": {\"sc_accuracy\": 0.5441, \"sica_accuracy\": 0.5392, \"delta_pp\": -0.49, \"n\": 204, \"mcnemar_b\": 6, \"mcnemar_c\": 5, \"mcnemar_p\": 1, \"mcnemar_significant\": false, \"fleiss_kappa_raw\": 0.4124, \"eff_k\": 2.17}}, \"exp-063-llama8b-folio204-16639\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:40:38.262Z\", \"updated_at\": \"2026-05-19T12:02:49.523Z\", \"hypothesis\": \"LLaMA-3.1-8B-Instruct 在 FOLIO-204 上 SICA vs SC。此前 exp-020 在不同服务器上跑过 (SC=63.2%, delta=-2.45pp)，本实验在 westd-16639 复现并用修正后的 alphabetical tie-breaking SC。parent=exp-020\", \"parent\": \"exp-020\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8004/v1 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp-063-llama8b-folio204-16639/results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct\", \"eval_data\": \"data/folio_full.json\", \"log_path\": \"results/exp-063-llama8b-folio204-16639/exp063.log\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.6618, \"sica_accuracy\": 0.6176, \"delta_pp\": -4.41, \"n\": 204, \"mcnemar_b\": 16, \"mcnemar_c\": 7, \"mcnemar_p\": 0.0931, \"mcnemar_significant\": false}, \"completed_at\": \"2026-05-19T11:20:59.372Z\"}, \"exp-063-llama8b-folio204\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T11:34:18.492Z\", \"updated_at\": \"2026-05-19T11:34:19.817Z\", \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 0.6618, \"sica_accuracy\": 0.6176, \"delta_pp\": -4.41}}, \"exp-061-qwen7b-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:18:30.356Z\", \"updated_at\": \"2026-05-19T11:34:17.303Z\", \"hypothesis\": \"Qwen2.5-7B-Instruct 在 FOLIO-204 上 SICA vs SC。SC 预计 55-65%（介于 Mistral-7B ~55% 和 Qwen2.5-14B ~75% 之间），可能在 Goldilocks zone。\", \"parent\": \"exp-033\", \"spec\": {\"server\": \"westd-25068\", \"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8002/v1 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp061_qwen25_7b_folio204/exp061_results.json --save-intermediates\", \"gpu\": \"cuda:2\", \"model_name\": \"Qwen2.5-7B-Instruct\", \"data_count\": 204, \"seed\": 42, \"data_path\": \"data/folio_full.json\", \"checkpoint_source\": \"pretrained:/root/autodl-tmp/models/Qwen2.5-7B-Instruct\", \"eval_data\": \"data/folio_full.json\"}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 0.7598, \"sica_accuracy\": 0.7647, \"delta_pp\": 0.49}, \"checkpoint_path\": \"results/exp061_qwen25_7b_folio204/exp061_results.json\", \"log_path\": \"results/exp061_qwen25_7b_folio204/\", \"completed_at\": \"2026-05-19T11:18:36.357Z\"}, \"exp-059-cross-qwen3-extractor\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:45:04.278Z\", \"updated_at\": \"2026-05-19T11:34:15.561Z\", \"hypothesis\": \"Qwen3-14B cross-model extraction should produce higher quality FOL constraints than Mistral-7B self-extraction (breaking confirmation bias), leading to higher SICA discriminative rate and accuracy delta over SC baseline.\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python scripts/cross_model_extract.py --traces-dir results/exp033_mistral_7b_folio204/intermediates --output results/exp059_cross_qwen3_extractor/exp059_results.json --qwen3-nothink --temperature 0.3\", \"server\": \"westd-25068\", \"data_path\": \"/root/symb_invariant_consensus/results/exp033_mistral_7b_folio204/intermediates\", \"data_count\": 204, \"model_name\": \"Qwen3-14B (extractor) + Mistral-7B (trace generator)\", \"seed\": \"n/a\", \"checkpoint_source\": \"Qwen/Qwen3-14B from /root/autodl-tmp/models/Qwen3-14B\", \"eval_data\": \"FOLIO-204 validation set (Mistral-7B K=12 traces from exp-033)\"}, \"conclusion\": \"success\", \"metrics\": {\"n\": 204, \"cross_sica_accuracy\": 0.6029, \"orig_sica_accuracy\": 0.5931, \"sc_accuracy\": 0.5588, \"delta_cross_vs_sc_pp\": 4.41, \"delta_cross_vs_orig_pp\": 0.98}, \"checkpoint_path\": \"results/exp059_cross_qwen3_extractor/exp059_results.json\", \"log_path\": \"results/exp059_cross_qwen3_extractor/\", \"completed_at\": \"2026-05-19T11:18:35.259Z\"}, \"exp-063\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:40:39.276Z\", \"updated_at\": \"2026-05-19T11:20:57.939Z\", \"hypothesis\": \"LLaMA-3.1-8B-Instruct FOLIO-204 SICA vs SC（Meta 架构覆盖）。exp-020 旧数据 SC=63.2% delta=-2.45pp，本实验用修正 tie-breaking 重跑。parent=exp-020\", \"parent\": \"exp-020\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8004/v1 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp-063-llama8b-folio204-16639/exp063_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Meta-Llama-3.1-8B-Instruct (off-the-shelf)\", \"eval_data\": \"FOLIO-204\", \"log_path\": \"results/exp-063-llama8b-folio204-16639/exp063.log\", \"checkpoint_path\": \"N/A\"}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 0.6618, \"sica_accuracy\": 0.6176, \"delta_pp\": -4.41}, \"completed_at\": \"2026-05-19T11:20:57.939Z\"}, \"exp-040-qwen3-pw600-16639\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:01:31.954Z\", \"updated_at\": \"2026-05-19T11:03:11.142Z\", \"hypothesis\": \"Qwen3-14B non-thinking 在 ProofWriter-600 全量上 SICA vs SC：跨模型代际验证 capability trap 在 PW 数据集上是否持续。与 exp-039 (Qwen2.5-14B PW-600) 对比代际差异。\", \"spec\": {\"command\": \"run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8001/v1 --model auto --seed 42 --pw-data data/proofwriter_full.json --folio-data data/empty.json --math-data data/empty.json\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen3-14B (non-thinking)\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen3-14B (cached, enable_thinking=false)\", \"eval_data\": \"ProofWriter-600\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp033_qwen3_14b_pw600_nonthinking/results.json\", \"log_path\": \"/root/symb_invariant_consensus/results/exp033_qwen3_14b_pw600_nonthinking/exp033.log\"}, \"notes\": \"westd-16639 实际目录: exp033_qwen3_14b_pw600_nonthinking, tmux: exp033, port: 8001, GPU 1. 162/600 (27.0%) at 22:28 UTC. Qwen3-14B thinking=false, 推理速度约为 Qwen2.5-14B 的一半。\", \"conclusion\": \"negative\", \"metrics\": {\"n\": 600, \"sc_accuracy\": 0.85, \"sica_accuracy\": 0.8567, \"delta_pp\": 0.67, \"extraction_rate\": 0.997, \"contradiction_rate\": 0.004, \"wall_time_min\": 1032.2, \"failure_type\": \"Type A (confirmation bias)\"}, \"completed_at\": \"2026-05-19T11:01:11.894Z\"}, \"exp-062-gemma27b-folio204\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:41:54.628Z\", \"updated_at\": \"2026-05-19T09:01:49.427Z\", \"hypothesis\": \"Gemma-3-27B-IT (Google 架构) FOLIO-204 SICA vs SC。跨模型家族验证 regime-dependent pattern。27B 能力预计在 Qwen2.5-14B (~75% SC) 和 Qwen3-14B (~85% SC) 之间。\", \"spec\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:3\", \"model_name\": \"gemma-3-27b-it\", \"data_count\": 204, \"seed\": 42, \"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8003/v1 --model auto --folio-data data/folio_full.json --math-data data/empty.json --pw-data data/empty.json --output results/exp062_gemma27b_folio204/exp062_results.json --save-intermediates\", \"data_path\": \"data/folio_full.json\", \"tmux_session\": \"exp062_run\", \"vllm_session\": \"exp062_vllm\", \"vllm_max_model_len\": 8192}}, \"exp-065-qwen7b-pw600\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T08:49:16.855Z\", \"updated_at\": \"2026-05-19T08:54:31.474Z\", \"hypothesis\": \"Qwen2.5-7B 在 PW-D5-600 上 SICA vs SC。FOLIO SC=75.98% (confirmation bias)，PW 更难 SC 预计更低，测试不同 regime。parent=exp-061\", \"parent\": \"\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --seed 42 --api-base http://localhost:8010/v1 --model auto --folio-data data/empty.json --math-data data/empty.json --pw-data data/proofwriter_full.json --output results/exp065_qwen7b_pw600/exp065_results.json\", \"server\": \"westd-25068\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:0\", \"port\": 8010, \"tmux_vllm\": \"exp065_vllm\", \"tmux_run\": \"exp065_run\"}}, \"exp-060-cross-qwen25-14b-extractor\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:38:50.075Z\", \"updated_at\": \"2026-05-19T08:33:33.071Z\", \"hypothesis\": \"Qwen2.5-14B 跨模型提取 FOL 约束。与 exp-033 (Mistral self-extraction) 和 exp-059 (Qwen3 cross-extraction) 对比。parent=exp-033\", \"spec\": {\"command\": \"python scripts/cross_model_extract.py --traces-dir results/exp033_mistral_7b_folio204/intermediates --api-base http://localhost:8001/v1 --model auto --temperature 0.3 --output results/exp060_cross_qwen25_14b_extractor/exp060_results.json --resume\", \"server\": \"westd-25068\", \"data_path\": \"results/exp033_mistral_7b_folio204/intermediates\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 0, \"checkpoint_path\": \"results/exp060_cross_qwen25_14b_extractor/exp060_results.json\", \"log_path\": \"results/exp060_cross_qwen25_14b_extractor/exp060.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T08:32:15.336Z\", \"metrics\": {\"n\": 204, \"cross_sica_accuracy\": 0.5833, \"orig_sica_accuracy\": 0.5931, \"sc_accuracy\": 0.5588, \"delta_cross_vs_sc_pp\": 2.45, \"delta_cross_vs_orig_pp\": -0.98, \"divergence_rate\": 0.059, \"wall_time_min\": 106.1}}, \"exp-057-mistral-folio204-t03\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:49:57.330Z\", \"updated_at\": \"2026-05-19T07:37:40.489Z\", \"hypothesis\": \"T=0.3 低温 traces 更确定性更一致，SICA delta < T=0.7 的 +4.90pp。与 exp-054 (T=1.0, +0.49pp) 共同形成 T sensitivity ablation curve。parent=exp-033, D060 analysis paper\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.3 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --folio-data data/folio_full.json --math-data data/empty.json --pw-data data/empty.json --output results/exp057_mistral_folio204_t03/exp057_results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"n/a\", \"eval_data\": \"data/folio_full.json\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T04:20:43.571Z\"}, \"failure_reason\": \"cron auto-resolved as failed (false positive: experiment completed successfully, data n=204 verified)\", \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 0.5833, \"sica_accuracy\": 0.5686, \"delta_pp\": -1.47, \"mcnemar_p\": 0.5488}, \"completed_at\": \"2026-05-19T04:20:44.783Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T04:20:49.931597+00:00\"}]}}, \"exp-034\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:15:24.666Z\", \"updated_at\": \"2026-05-19T05:50:00.000Z\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 ProofWriter-600 上 SICA vs SC（westd-25068 重跑）：在 full 600 题上验证 capability trap，复现 sica_expanded_14b 的 PW 子集结果（delta=+0.3pp）。代替原 StrategyQA 实验（exp-034 v1 因 extraction prompt bug + 平台 kill 失败）。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && CUDA_VISIBLE_DEVICES=1 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-14B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8001 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp034.log 2>&1 & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8001/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/proofwriter_full.json --folio-data data/empty.json --output results/exp034_qwen25_14b_proofwriter/exp034_results.json --save-intermediates 2>&1 | tee results/exp034_qwen25_14b_proofwriter/exp034.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:1\"], \"pid\": \"68543\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-034.log\", \"submitted_at\": \"2026-05-18T17:44:32.378Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12424.8, \"gpu_hours\": 3.45}, \"conclusion\": \"negative\", \"metrics\": {\"n_problems\": 93, \"n_target\": 600, \"completion_pct\": 15.5, \"sica_accuracy\": 77.42, \"sc_accuracy\": 74.19, \"delta_pp\": 3.23, \"sica_correct\": 72, \"sc_correct\": 69, \"mcnemar_discordant_b\": 6, \"mcnemar_discordant_c\": 3, \"mcnemar_p_value\": 0.5078, \"c0_non_unanimous_rate\": 0.581, \"avg_majority_frac\": 0.8324, \"extraction_rate\": 99.19, \"contradiction_rate\": 11.83, \"problems_with_contradictions\": 11, \"avg_unique_constraints\": 35.6, \"total_constraints\": 14437, \"unique_constraints\": 3308, \"dedup_ratio\": 22.9, \"k\": 12, \"level\": \"OWA-D5\", \"gt_distribution\": {\"True\": 32, \"False\": 28, \"Unknown\": 33}, \"wall_time_s\": 6086.4, \"status_note\": \"INCOMPLETE: crashed at 93/600 (python not found after conda env lost)\"}, \"notes\": \"v4 完成。tmux=exp034_run, westd-25068 cuda:1。Qwen2.5-14B on PW-600, delta=+0.50pp (不显著)。\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp034_qwen25_14b_proofwriter/exp034_results.json\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-034.log\", \"reproduce\": {\"finished_at\": \"2026-05-18T19:02:28.841Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:02:32.634997+00:00\"}]}, \"completed_at\": \"2026-05-18T21:11:37.217Z\"}, \"exp-039-14b-pw600-16639\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:01:31.038Z\", \"updated_at\": \"2026-05-19T04:53:50.957Z\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 ProofWriter-600 全量上 SICA vs SC（westd-16639 重跑）：验证 capability trap 在 PW 数据集全量规模上是否持续。复现 sica_expanded_14b 的 PW 子集结果（delta=+0.3pp）。\", \"spec\": {\"command\": \"run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8000/v1 --model auto --seed 42 --pw-data data/proofwriter_full.json --folio-data data/empty.json --math-data data/empty.json\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct (cached)\", \"eval_data\": \"ProofWriter-600\"}, \"notes\": \"westd-16639 实际目录: exp032_qwen25_14b_pw600, tmux: exp032, port: 8000, GPU 0. 263/600 (43.8%) at 22:28 UTC.\", \"reproduce\": {\"finished_at\": \"2026-05-19T04:53:49.681Z\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T04:53:50.957Z\", \"metrics\": {\"sica_accuracy\": 71.5, \"sc_accuracy\": 73.5, \"delta_pp\": -2.0, \"n_problems\": 600, \"extraction_rate\": 99.2, \"wall_time_min\": 659.6}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp032_qwen25_14b_pw600/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp032_qwen25_14b_pw600/\"}, \"exp-058-mistral-folio204-t05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T03:10:13.574Z\", \"updated_at\": \"2026-05-19T04:38:50.593Z\", \"hypothesis\": \"T=0.5 delta 介于 T=0.3 和 T=0.7 之间，形成温度-SICA delta 曲线。与 exp-033 (T=0.7, +4.90pp) 和 exp-054 (T=1.0, +0.49pp) 共同构成 4 点 T sensitivity ablation。parent=exp-033, D060 analysis paper\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.5 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 42 --folio-data data/folio_full.json --math-data data/empty.json --pw-data data/empty.json --output results/exp058_mistral_folio204_t05/exp058_results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (base, no finetune)\", \"eval_data\": \"FOLIO-204 (data/folio_full.json)\"}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 57.84, \"sica_accuracy\": 57.35, \"delta_pp\": -0.49, \"mcnemar_p\": 1, \"discordant_b\": 3, \"discordant_c\": 2, \"n_problems\": 204, \"n_completed\": 204, \"extraction_rate\": 97, \"wall_time_min\": 80}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp058_mistral_folio204_t05/exp058_results.json\", \"log_path\": \"/root/symb_invariant_consensus/results/exp058_mistral_folio204_t05/exp058.log\", \"completed_at\": \"2026-05-19T04:38:50.593Z\"}, \"exp-051-mistral-k-sensitivity\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:32:12.672Z\", \"updated_at\": \"2026-05-19T04:37:35.722Z\", \"hypothesis\": \"Mistral-7B K sensitivity on FOLIO-204: K=[4,8,16,20]（K=12 已有 exp-033 delta=+4.90pp）。验证正向结果对 K 选择是否稳健。Reviewer 必问 ablation。parent=exp-033\", \"spec\": {\"command\": \"bash scripts/run_exp051_k_sensitivity.sh\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 816, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp051_mistral_k_sensitivity/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp051_mistral_k_sensitivity/k20/k20.log\", \"metrics\": {\"K4\": {\"SC\": 54.41, \"SICA\": 52.94, \"delta\": -1.47, \"b\": 7, \"c\": 10, \"McNemar_p\": 0.6291}, \"K8\": {\"SC\": 57.35, \"SICA\": 56.37, \"delta\": -0.98, \"b\": 4, \"c\": 6, \"McNemar_p\": 0.7539}, \"K12_exp033\": {\"SC\": 54.41, \"SICA\": 59.31, \"delta\": 4.9, \"b\": 12, \"c\": 2, \"McNemar_p\": 0.0129}, \"K16\": {\"SC\": 55.88, \"SICA\": 57.35, \"delta\": 1.47, \"b\": 10, \"c\": 7, \"McNemar_p\": 0.6291}, \"K20\": {\"SC\": 57.35, \"SICA\": 59.31, \"delta\": 1.96, \"b\": 5, \"c\": 1, \"McNemar_p\": 0.2188}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T04:37:33.691Z\", \"notes\": \"K sensitivity 完整 5 点数据确认 K=12 是最优点（delta=+4.90pp, p=0.013）。K<12 SICA 不如 SC（K=4: -1.47pp, K=8: -0.98pp），K>12 delta 回落但仍为正（K=16: +1.47pp, K=20: +1.96pp）。整体呈 peaked 曲线（非严格倒 U，K=20 略高于 K=16），但 K=12 peak 显著且两侧衰减明确。McNemar 仅 K=12 显著（p=0.013），其余 K 值均不显著。\"}, \"exp-055-multitemp-mistral-folio\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:17:09.293Z\", \"updated_at\": \"2026-05-19T03:53:56.005Z\", \"hypothesis\": \"Multi-temperature sampling 通过强制 trace diversity 提升 Effective-K，预期 SICA delta > exp-033 的 +4.9pp。混合 T=0.3/0.7/1.2 各 4 traces 比单一 T=0.7 的 12 traces 产生更多独立视角，从而让 MAX-SAT 有更多 discriminative 信号。parent=exp-033, D059\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python -u run_multi_temp.py --mode vllm --temperatures 0.3,0.7,1.2 --k-per-temp 4,4,4 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp055_multitemp_mistral_folio/exp055_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (pretrained)\", \"eval_data\": \"data/folio_full.json\"}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp055_multitemp_mistral_folio/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp055_multitemp_mistral_folio/exp055.log\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 57.84, \"sica_accuracy\": 57.84, \"delta_pp\": 0, \"discordant_b\": 5, \"discordant_c\": 5, \"mcnemar_p\": 1, \"significant\": false, \"agreement_rate\": 0.951, \"wall_time_min\": 83.2, \"temperatures\": \"0.3,0.7,1.2\", \"k_per_temp\": \"4,4,4\"}, \"completed_at\": \"2026-05-19T03:52:57.065Z\"}, \"exp-028b-qwen3-thinking-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:30:30.635Z\", \"updated_at\": \"2026-05-19T03:34:08.736Z\", \"hypothesis\": \"Qwen3-14B thinking mode (enable_thinking=True, 32K context) 在 FOLIO-204 上 SICA vs SC。D028 pilot (35/204, delta=+2.86pp) 被 kill。thinking mode 产生更 diverse+higher-quality reasoning traces，如果同时提升 trace quality 和 diversity，可能打破 14B 级别的 capability trap。parent=exp-028\", \"spec\": {\"command\": \"bash run_exp028b.sh (tmux session: exp028b)\", \"server\": \"westd-25068\", \"gpu_ids\": [\"cuda:3\"], \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"port\": 8003, \"max_model_len\": 32768, \"max_tokens\": 16384, \"temperature\": 0.7, \"k\": 12, \"mode\": \"thinking\"}, \"reproduce\": {\"finished_at\": \"2026-05-19T03:19:42.424Z\"}, \"failure_reason\": \"cuda:3 回收给 exp-058 T sensitivity ablation（资源冲突，非 OOM）。166/204 已完成，待 exp-058 完成后 resume。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-19T03:19:44.303Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T03:19:49.420748+00:00\"}]}, \"notes\": \"失败根因：exp-058 部署到 cuda:3+port:8003 覆盖了 exp-028b 的 vLLM（非 OOM）。166/204 已完成，intermediates 完整保存。支持 resume（仅需 38 题 ~90min），但需等 exp-058 完成释放 cuda:3。\"}, \"exp-052\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:20:17.415Z\", \"updated_at\": \"2026-05-19T02:47:07.125Z\", \"hypothesis\": \"Seed replication of exp-033: the +4.90pp improvement on FOLIO-204 with Mistral-7B using symbolic invariant consensus (K=12) is reproducible across different random seeds, confirming the result is not a statistical fluke.\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 123 --math-data data/empty.json --pw-data data/empty.json --strategyqa-data data/empty.json --folio-data data/folio_full.json --output results/exp052_mistral_folio204_seed123/exp052_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 123}, \"metrics\": {\"n\": 204, \"sc_accuracy\": 53.9, \"sica_accuracy\": 57.4, \"sc_correct\": 110, \"sica_correct\": 117, \"delta_pp\": 3.43, \"discordant_b\": 8, \"discordant_c\": 1, \"extraction_rate\": 0.971, \"contradiction_rate\": 0.034, \"wall_time_min\": 81.9, \"mcnemar_p\": 0.0391, \"significant\": true}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T01:03:00.000Z\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp052_mistral_folio204_seed123/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp052_mistral_folio204_seed123/exp052.log\", \"notes\": \"Seed=123: SICA=57.35% vs SC=53.92%, delta=+3.43pp, b=8, c=1, p=0.039. High entropy 区域 delta=+7.14pp。2/3 seeds 显著。\", \"parent\": \"exp-033\"}, \"exp-054-mistral-folio204-t10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T01:17:52.972Z\", \"updated_at\": \"2026-05-19T02:44:50.785Z\", \"hypothesis\": \"T=1.0 增大 trace diversity，Adaptive SICA（high entropy 子集）delta 应 ≥ T=0.7 的 +4.9pp。更高温度 → 更多 high-entropy 问题 → SICA 在更大子集上有效 → overall delta 可能更大。同时测试 exp-033 (+4.9pp at T=0.7) 对温度的敏感性。parent=exp-033\", \"parent\": \"exp-033\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 1.0 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --folio-data data/folio_full.json --output results/exp054_mistral_folio204_t10/exp054_results.json --save-intermediates\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"Mistral-7B-Instruct-v0.3 (pretrained, no fine-tuning)\", \"eval_data\": \"data/folio_full.json\", \"log_path\": \"results/exp054_mistral_folio204_t10/exp054.log\", \"checkpoint_path\": \"results/exp054_mistral_folio204_t10/exp054_results.json\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T02:44:47.966Z\", \"metrics\": {\"n\": 204, \"sc_accuracy\": 54.9, \"sica_accuracy\": 55.4, \"delta_pp\": 0.49, \"discordant_b\": 5, \"discordant_c\": 4, \"mcnemar_chi2\": 0.1111, \"mcnemar_p\": 0.7389, \"extraction_rate\": 97.3, \"contradiction_rate\": 3, \"wall_time_min\": 83}}, \"exp-048-llama8b-pw600\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:30:33.025Z\", \"updated_at\": \"2026-05-19T02:21:10.720Z\", \"hypothesis\": \"LLaMA-3.1-8B-Instruct 在 ProofWriter-600 上 SICA vs SC。FOLIO-204 上 LLaMA-8B SC=63.2% delta=-2.45pp (exp-020)。PW 是更结构化的形式推理数据集，测试 SICA 在 PW 上对低能力模型是否有效（补充 regime boundary 跨域证据）。parent=exp-020\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/proofwriter_full.json --folio-data data/empty.json --output results/exp048_llama8b_pw600/exp048_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:3\", \"tmux_session\": \"exp048_run\"}}, \"exp-046-mistral-pw600\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:16:46.346Z\", \"updated_at\": \"2026-05-19T01:15:51.422Z\", \"hypothesis\": \"Mistral-7B-Instruct-v0.3 在 ProofWriter-600 上 SICA vs SC：验证 regime boundary 跨域泛化。exp-033 (Mistral FOLIO-204) 显示 +4.90pp (p=0.013)，如果 PW-600 也显示正向 delta，则 regime-dependent capability trap 不是 FOLIO-specific artifact。\", \"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-18T20:17:41.279Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp046_mistral_7b_pw600 && CUDA_VISIBLE_DEVICES=2 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Mistral-7B-Instruct-v0.3 --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8002 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp046.log 2>&1 & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/proofwriter_full.json --folio-data data/empty.json --output results/exp046_mistral_7b_pw600/exp046_results.json --save-intermediates 2>&1 | tee results/exp046_mistral_7b_pw600/exp046.log\\\"\", \"finished_at\": \"2026-05-19T01:11:58.516Z\", \"training_hours\": 4.9}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp046_mistral_7b_pw600 && CUDA_VISIBLE_DEVICES=2 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Mistral-7B-Instruct-v0.3 --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8002 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp046.log 2>&1 & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/proofwriter_full.json --folio-data data/empty.json --output results/exp046_mistral_7b_pw600/exp046_results.json --save-intermediates 2>&1 | tee results/exp046_mistral_7b_pw600/exp046.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:2\"], \"pid\": \"95707\", \"log_path\": \"/root/symb_invariant_consensus/results/exp046_mistral_7b_pw600/exp046.log\", \"submitted_at\": \"2026-05-18T20:17:43.014Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp046_mistral_7b_pw600/\", \"wall_clock_seconds\": 17888.4, \"gpu_hours\": 4.97}, \"pid\": \"95707\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-046-mistral-pw600.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T01:12:02.839310+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 600, \"sc_accuracy\": 39.33, \"sica_accuracy\": 36.5, \"delta_pp\": -2.83, \"sc_wins\": 30, \"sica_wins\": 13, \"mcnemar_p\": 0.0095, \"significant\": true, \"dataset\": \"ProofWriter-D5-600\", \"model\": \"Mistral-7B-Instruct-v0.3\"}, \"completed_at\": \"2026-05-19T01:15:51.422Z\"}, \"exp-053\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:20:18.405Z\", \"updated_at\": \"2026-05-19T01:05:00.000Z\", \"hypothesis\": \"Seed replication of exp-033: the +4.90pp improvement on FOLIO-204 with Mistral-7B using symbolic invariant consensus (K=12) is reproducible across different random seeds, confirming the result is not a statistical fluke.\", \"spec\": {\"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 456 --math-data data/empty.json --pw-data data/empty.json --strategyqa-data data/empty.json --folio-data data/folio_full.json --output results/exp053_mistral_folio204_seed456/exp053_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 456}, \"metrics\": {\"n\": 204, \"sc_accuracy\": 56.37, \"sica_accuracy\": 55.88, \"sc_correct\": 115, \"sica_correct\": 114, \"delta_pp\": -0.49, \"discordant_b\": 2, \"discordant_c\": 3, \"extraction_rate\": 0.97, \"contradiction_rate\": 0.033, \"wall_time_min\": 80.8, \"mcnemar_p\": 1.0, \"significant\": false}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T01:02:00.000Z\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp053_mistral_folio204_seed456/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp053_mistral_folio204_seed456/exp053.log\", \"notes\": \"Seed=456: SICA=55.88% vs SC=56.37%, delta=-0.49pp, b=2, c=3, p=1.0. SC baseline 最高，capability trap 确认。跨 seed SC vs delta Pearson r=-0.8973。\", \"parent\": \"exp-033\"}, \"exp-050b-mistral-icl-oracle\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T21:31:50.554Z\", \"updated_at\": \"2026-05-18T23:19:54.810Z\", \"hypothesis\": \"Increasing vLLM max_model_len from 8192 to 16384 will resolve the context length overflow (input ~4400 + max_tokens 4096 > 8192) that caused 86% failure in exp-050, allowing Mistral-7B ICL Oracle with 5 gold FOL examples to complete evaluation on all 199 FOLIO problems.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Mistral-7B-Instruct-v0.3 --max-model-len 16384 --gpu-memory-utilization 0.90 --port 8002 --dtype auto --trust-remote-code --enforce-eager && python -u run_icl_oracle.py --api-base http://localhost:8002/v1 --model auto --k 12 --data data/folio_full.json --output results/exp050b_mistral_icl_oracle/exp050b_results.json --seed 42 --save-intermediates --temperature 0.7 --max-tokens 4096\", \"server\": \"westd-16639\", \"gpu_ids\": [\"cuda:2\"], \"data_path\": \"data/folio_full.json\", \"data_count\": 199, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/Mistral-7B-Instruct-v0.3\", \"eval_data\": \"data/folio_full.json\"}, \"log_path\": \"/root/symb_invariant_consensus/results/exp050b_mistral_icl_oracle/exp050b.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp050b_mistral_icl_oracle/\", \"metrics\": {\"n\": 199, \"sc_accuracy\": 57.79, \"sica_accuracy\": 54.27, \"delta_pp\": -3.52, \"sc_correct\": 115, \"sica_correct\": 108, \"discordant_b\": 6, \"discordant_c\": 13, \"mcnemar_p\": 0.167, \"significant\": false, \"wall_time_min\": 93.8, \"extraction_success\": 2333, \"extraction_fail\": 55, \"per_answer\": {\"True\": {\"n\": 70, \"sica_acc\": 50, \"sc_acc\": 54.29}, \"False\": {\"n\": 61, \"sica_acc\": 36.07, \"sc_acc\": 44.26}, \"Unknown\": {\"n\": 68, \"sica_acc\": 75, \"sc_acc\": 73.53}}}, \"conclusion\": \"negative\", \"notes\": \"ICL Oracle (5 gold FOL examples) on Mistral-7B FOLIO-199: SICA=54.27% vs SC=57.79%, delta=-3.52pp (p=0.167, ns). ICL boosted SC from vanilla 54.41% (exp-033) to 57.79% (+3.38pp), but SICA did not benefit. ICL improves individual trace quality enough to boost majority vote, but the resulting constraints become less diverse/discriminative for MaxSAT weighting. Confirms capability trap: better extraction quality does not translate to SICA gains when it also reduces beneficial disagreement.\", \"completed_at\": \"2026-05-18T23:16:14.227Z\"}, \"exp-050-mistral-icl-oracle-folio199\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:48:25.841Z\", \"updated_at\": \"2026-05-18T23:19:53.802Z\", \"hypothesis\": \"Providing 5 gold FOL annotations as in-context learning examples will significantly improve the quality of symbolic constraint extraction from Mistral-7B reasoning traces, leading to higher SICA accuracy over SC baseline on FOLIO-199\", \"spec\": {\"command\": \"python -u run_icl_oracle.py --api-base http://localhost:8002/v1 --model auto --k 12 --data data/folio_full.json --output results/exp050_mistral_icl_oracle_folio199/exp050_results.json --seed 42 --save-intermediates --resume\", \"server\": \"westd-16639\", \"gpu_ids\": [\"cuda:2\"], \"data_path\": \"data/folio_full.json\", \"data_count\": 199, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"description\": \"ICL Oracle experiment: 5 gold FOL annotations as few-shot examples for constraint extraction, evaluate SICA vs SC on remaining 199 FOLIO problems\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T23:19:53.802Z\"}, \"exp-049b-mistral-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T21:53:09.676Z\", \"updated_at\": \"2026-05-18T23:16:15.080Z\", \"hypothesis\": \"Mistral-7B LogiQA-200 v2: 修复 exp-049 部署失败（vLLM 启动但 pipeline 未运行，tmux session 丢失）。验证 Mistral 的 +4.90pp FOLIO 增益是否跨 LogiQA 复现。parent=exp-033\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/run_exp049b.sh\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"gpu_ids\": [\"cuda:3\"], \"port\": 8003, \"tmux_session\": \"exp049b\", \"vllm_version\": \"0.21.0\", \"output_dir\": \"/root/symb_invariant_consensus/results/exp049b_mistral_logiqa200\", \"log_path\": \"/root/symb_invariant_consensus/results/exp049b_mistral_logiqa200/exp049b.log\", \"vllm_log\": \"/tmp/vllm_exp049b.log\", \"params\": {\"k\": 12, \"temperature\": 0.7, \"max_tokens\": 4096, \"max_model_len\": 8192, \"gpu_memory_utilization\": 0.9, \"enforce_eager\": true, \"VLLM_USE_FLASHINFER_SAMPLER\": 0}}, \"log_path\": \"/root/symb_invariant_consensus/results/exp049b_mistral_logiqa200/exp049b.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp049b_mistral_logiqa200/\", \"metrics\": {\"n\": 200, \"sc_accuracy\": 51, \"sica_accuracy\": 51.5, \"delta_pp\": 0.5, \"sc_correct\": 102, \"sica_correct\": 103, \"discordant_b\": 6, \"discordant_c\": 5, \"mcnemar_p\": 1, \"significant\": false, \"wall_time_min\": 78.6, \"extraction_rate\": 0.9725, \"total_constraints\": 10659, \"unique_constraints\": 8934, \"contradiction_rate\": 0.0196}, \"conclusion\": \"negative\", \"notes\": \"Mistral-7B LogiQA-200: SICA=51.50% vs SC=51.00%, delta=+0.50pp (p=1.000, ns). Mistral's +4.90pp FOLIO advantage (exp-033) does not transfer to LogiQA. SC baseline 51% is near random for 4-choice MCQ. Consistent with exp-038 (14B LogiQA delta=-0.50pp): SICA provides no benefit on LogiQA regardless of model, likely because LogiQA's pragmatic reasoning resists symbolic constraint formalization.\", \"completed_at\": \"2026-05-18T23:16:15.080Z\"}, \"exp-044b-icl-oracle\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:16:44.204Z\", \"updated_at\": \"2026-05-18T22:59:34.846Z\", \"hypothesis\": \"ICL with Oracle Examples (v2, 正确模型 Qwen2.5-14B): 用 5 个 gold FOL annotations 作为 few-shot examples 教 LLM 提取高质量约束。如果 extraction quality 是 capability trap 瓶颈，oracle-guided extraction 应能产生更 discriminative 的约束，使 ICL-SICA > vanilla SICA (74.51%)。评测 199 题。v1 因使用错误模型 (Mistral-7B) 被 kill。\", \"server\": \"westd-25068\", \"gpu\": \"cuda:0\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-18T20:17:35.899Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp044b_icl_oracle_qwen14b && CUDA_VISIBLE_DEVICES=0 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-14B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8000 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp044b.log 2>&1 & sleep 120 && python -u run_icl_oracle.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8000/v1 --model auto --seed 42 --data data/folio_full.json --output results/exp044b_icl_oracle_qwen14b/results.json --save-intermediates 2>&1 | tee results/exp044b_icl_oracle_qwen14b/exp044b.log\\\"\", \"finished_at\": \"2026-05-18T22:57:51.205Z\", \"training_hours\": 2.67}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp044b_icl_oracle_qwen14b && CUDA_VISIBLE_DEVICES=0 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-14B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8000 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp044b.log 2>&1 & sleep 120 && python -u run_icl_oracle.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8000/v1 --model auto --seed 42 --data data/folio_full.json --output results/exp044b_icl_oracle_qwen14b/results.json --save-intermediates 2>&1 | tee results/exp044b_icl_oracle_qwen14b/exp044b.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:0\"], \"pid\": \"95429\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-044b-icl-oracle.log\", \"submitted_at\": \"2026-05-18T20:17:38.527Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 9716.3, \"gpu_hours\": 2.7}, \"pid\": \"95429\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-044b-icl-oracle.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T22:57:54.590178+00:00\"}]}, \"metrics\": {\"n\": 199, \"dataset\": \"FOLIO-199\", \"model\": \"Qwen2.5-14B-Instruct\", \"k\": 12, \"sica_accuracy\": 74.87, \"sc_accuracy\": 74.37, \"delta_pp\": 0.5, \"sica_correct\": 149, \"sc_correct\": 148, \"icl_examples\": 5, \"extraction_failure_rate\": 0.008}, \"conclusion\": \"negative\", \"checkpoint_path\": \"westd-25068:/root/symb_invariant_consensus/results/exp044b_icl_oracle_qwen14b/results.json\", \"completed_at\": \"2026-05-18T22:59:34.846Z\"}, \"exp-049-mistral-logiqa200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:30:34.577Z\", \"updated_at\": \"2026-05-18T21:53:04.043Z\", \"hypothesis\": \"Mistral-7B-Instruct-v0.3 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 Mistral delta=+4.90pp (exp-033, p=0.013)。14B 在 LogiQA 上 delta=-0.50pp (exp-038)。测试 regime boundary：Mistral 低 SC + 高 diversity 是否在 LogiQA 上也产生正向 SICA delta。parent=exp-033\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Mistral-7B-Instruct-v0.3 --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8003 --dtype auto --trust-remote-code --enforce-eager & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 42 --strategyqa-data data/logiqa_200.json --output results/exp049_mistral_logiqa200/exp049_results.json --save-intermediates\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"gpu_ids\": [\"cuda:3\"], \"tmux_session\": \"exp049\", \"output_dir\": \"results/exp049_mistral_logiqa200\", \"log_path\": \"results/exp049_mistral_logiqa200/exp049.log\", \"vllm_log\": \"/tmp/vllm_exp049.log\", \"port\": 8003}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T21:53:04.043Z\"}, \"exp-041-14b-folio204-16639\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:01:33.016Z\", \"updated_at\": \"2026-05-18T21:08:19.597Z\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 FOLIO-204 上 SICA vs SC（westd-16639 独立重跑）：在不同服务器上复现 exp-001/026 结果，验证 capability trap 的可复现性和排除服务器环境差异。\", \"spec\": {\"command\": \"run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8002/v1 --model auto --seed 42 --pw-data data/empty.json --folio-data data/folio_full.json --math-data data/empty.json\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct (cached)\", \"eval_data\": \"FOLIO-204\"}, \"reproduce\": {\"finished_at\": \"2026-05-18T20:15:00.713Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T20:15:02.129Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T20:15:05.317649+00:00\"}]}, \"metrics\": {\"n\": 204, \"dataset\": \"FOLIO-204\", \"model\": \"Qwen2.5-14B-Instruct\", \"k\": 12, \"sica_accuracy\": 75.49, \"sc_accuracy\": 77.45, \"delta_pp\": -1.96, \"sica_correct\": 154, \"sc_correct\": 158, \"mcnemar_discordant_b\": 0, \"mcnemar_discordant_c\": 4, \"mcnemar_p_value\": 0.125, \"extraction_rate\": 0.98, \"contradiction_rate\": 0.0097}, \"log_path\": \"/root/symb_invariant_consensus/results/exp036_qwen25_14b_folio204/exp036.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp036_qwen25_14b_folio204/results.json\"}, \"exp-045b-backward-verify\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:16:45.453Z\", \"updated_at\": \"2026-05-18T20:30:28.631Z\", \"hypothesis\": \"Backward Verification v2 (正确模型 Qwen2.5-14B): 翻转验证方向，对每个候选答案反向推理 premises，用 Z3 检查一致性。v1 使用错误模型 (Qwen-7B) 得到 -21pp，需确认 Qwen-14B 上是否仍为强 negative（预期是，因为根因是 FOL quality 而非 model capacity）。\", \"server\": \"westd-25068\", \"gpu\": \"cuda:3\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-18T20:17:45.787Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp045b_backward_qwen14b && CUDA_VISIBLE_DEVICES=3 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-14B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8003 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp045b.log 2>&1 & sleep 120 && python -u backward_verification.py --api-base http://localhost:8003/v1 --model auto --k 12 --data data/folio_full.json --output results/exp045b_backward_qwen14b/results.json --seed 42 --temperature 0.7 2>&1 | tee results/exp045b_backward_qwen14b/exp045b.log\\\"\"}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && mkdir -p results/exp045b_backward_qwen14b && CUDA_VISIBLE_DEVICES=3 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-14B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8003 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp045b.log 2>&1 & sleep 120 && python -u backward_verification.py --api-base http://localhost:8003/v1 --model auto --k 12 --data data/folio_full.json --output results/exp045b_backward_qwen14b/results.json --seed 42 --temperature 0.7 2>&1 | tee results/exp045b_backward_qwen14b/exp045b.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:3\"], \"pid\": \"95988\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-045b-backward-verify.log\", \"submitted_at\": \"2026-05-18T20:17:47.319Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 761.3, \"gpu_hours\": 0.21}, \"pid\": \"95988\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-045b-backward-verify.log\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-18T20:30:28.631Z\"}, \"exp-045-backward-verification\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:01:40.541Z\", \"updated_at\": \"2026-05-18T20:30:00.573Z\", \"hypothesis\": \"Backward Verification: 翻转验证方向，对每个候选答案反向推理需要哪些 premises 成立/矛盾，用 Z3 检查哪个答案与 premises 最一致（矛盾最少）。如果 forward extraction 质量是瓶颈，backward verification 绕过 extraction 直接用 solver 判断一致性，可能打破 capability trap。\", \"server\": \"westd-25068\", \"gpu\": \"cuda:3\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-18T19:16:32.740Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_backward_verification.sh 3 8003\\\"\", \"finished_at\": \"2026-05-18T19:41:02.660Z\", \"training_hours\": 0.41}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_backward_verification.sh 3 8003\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:3\"], \"pid\": \"83115\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-045-backward-verification.log\", \"submitted_at\": \"2026-05-18T19:16:34.043Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4146.5, \"gpu_hours\": 1.15}, \"pid\": \"83115\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-045-backward-verification.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:41:05.769423+00:00\"}]}, \"conclusion\": \"negative\", \"notes\": \"v1: 可能使用了 Qwen-7B 残留 vLLM (exp-035 遗留 port 8003)。BV=53.92% vs SC=75.00%, delta=-21.08pp。Z3 SAT rate 95.3%=无判别力。True bias 72.5% vs gold 35.3%。根因：backward FOL generation 质量同样差，验证方向不解决 capability trap。即使换正确模型 (-21pp 幅度过大) 可能仍 negative。建议 Director 决策是否用 Qwen2.5-14B 重跑 v2。\", \"completed_at\": \"2026-05-18T20:25:40.512Z\"}, \"exp-038-14b-logiqa200-16639\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:01:33.795Z\", \"updated_at\": \"2026-05-18T20:27:39.296Z\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 LogiQA 2.0 (200题) 上 SICA vs SC：跨数据集验证 capability trap。LogiQA 是多选逻辑推理（非二元分类），constraint extraction 和 Z3 formalization 需要适配不同推理类型。\", \"spec\": {\"command\": \"run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 42 --strategyqa-data data/logiqa_200.json --folio-data data/empty.json --math-data data/empty.json --pw-data data/empty.json\", \"server\": \"westd-16639\", \"data_path\": \"/root/symb_invariant_consensus/data/logiqa_200.json\", \"data_count\": 200, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct (cached)\", \"eval_data\": \"LogiQA-200\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp038_qwen25_14b_logiqa200/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp038_qwen25_14b_logiqa200/exp038.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-18T20:07:36.880Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T20:07:38.091Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T20:07:40.768677+00:00\"}]}, \"metrics\": {\"n\": 200, \"dataset\": \"LogiQA-200\", \"model\": \"Qwen2.5-14B-Instruct\", \"k\": 12, \"sica_accuracy\": 78, \"sc_accuracy\": 78.5, \"delta_pp\": -0.5, \"mcnemar_p\": 1, \"sica_correct\": 156, \"sc_correct\": 157, \"discordant_b\": 1, \"discordant_c\": 2, \"both_correct\": 155, \"both_wrong\": 42, \"extraction_rate\": 0.864, \"fail_empty_rate\": 0.122, \"avg_unique_constraints\": 26.7, \"contradiction_rate\": 0.008, \"wall_time_min\": 126.8}, \"notes\": \"实验成功完成200/200题，之前被自动监控误判为failed。结果：SICA略逊于SC(-0.5%)，McNemar p=1.0完全不显著。仅3例disagreement(sica_only=1, sc_only=2)。extraction_rate=86.4%低于FOLIO实验(~90%+)，fail_empty=12.2%较高——LogiQA的非形式化推理对constraint extraction更难。contradiction_rate仅0.8%，几乎无矛盾检测。结论：SICA在LogiQA非形式逻辑推理上无增益，capability trap假设在此数据集上未验证。\"}, \"exp-033\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:42:09.819Z\", \"updated_at\": \"2026-05-18T20:25:06.703Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && CUDA_VISIBLE_DEVICES=0 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Mistral-7B-Instruct-v0.3 --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8000 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp033.log 2>&1 & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8000/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp033_mistral_7b_folio204/exp033_results.json --save-intermediates 2>&1 | tee results/exp033_mistral_7b_folio204/exp033.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:0\"], \"pid\": \"65773\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-033.log\", \"submitted_at\": \"2026-05-18T17:42:09.638Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"wall_clock_seconds\": 5875.8, \"gpu_hours\": 1.63}, \"hypothesis\": \"Cross-family validation: Mistral-7B-Instruct-v0.3 在 FOLIO-204 全量上 SICA vs SC。验证 capability trap 跨模型家族在 full dataset 上是否持续（D012 pilot exp-010 已确认 delta=0, n=60）。\", \"reproduce\": {\"finished_at\": \"2026-05-18T19:02:16.294Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:02:18.863472+00:00\"}]}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp033_mistral_7b_folio204/exp033_results.json\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-033.log\", \"metrics\": {\"n_problems\": 204, \"sica_accuracy\": 59.31, \"sc_accuracy\": 54.41, \"delta_pp\": 4.9, \"sica_correct\": 121, \"sc_correct\": 111, \"mcnemar_discordant_b\": 12, \"mcnemar_discordant_c\": 2, \"mcnemar_p_value\": 0.0129, \"c0_non_unanimous_rate\": 0.8137, \"avg_majority_frac\": 0.7515, \"extraction_rate\": 97.14, \"contradiction_rate\": 3.5, \"problems_with_contradictions\": 128, \"avg_unique_constraints\": 39.3, \"maxsat_mean_sat_ratio\": 0.9609, \"total_constraints\": 14042, \"unique_constraints\": 8021, \"wall_time_min\": 81.4, \"k\": 12}, \"conclusion\": \"success\", \"notes\": \"Mistral-7B FOLIO-204: SICA 59.31% vs SC 54.41%, delta=+4.90pp (McNemar p=0.013, significant). 首次 SICA 显著超越 SC。关键因素：C0=81.37%（远高于 Qwen-7B 的 55%），高 diversity 使 SC majority vote 退化，而 SICA MaxSAT 仍能从 noisy traces 中提取信号。Discordant: SICA-only=12, SC-only=2, 高度不对称。但绝对准确率低（59% vs Qwen-7B 77%），说明 Mistral-7B 基础推理能力弱。结论：capability trap 非普遍现象，依赖 diversity/quality 平衡——高 diversity + 低 quality 时 SICA 有优势。\", \"completed_at\": \"2026-05-18T19:20:05.477Z\"}, \"exp-042b-premise-formal\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:13:55.356Z\", \"updated_at\": \"2026-05-18T20:10:14.058Z\", \"hypothesis\": \"Premise-Only Formalization (重启): 绕过 CoT trace extraction，直接让 LLM 将 FOLIO premises + conclusion 形式化为 FOL，用 Z3 验证逻辑蕴含。K=12 独立 formalization + majority vote。如果 extraction quality 是 capability trap 的瓶颈，直接 formalization 应能产生更准确的约束，使 Premise-FOL > vanilla SICA。exp-042 因 vLLM 未启动失败，本次重启。\", \"parent\": \"exp-042-premise-formalization\", \"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-18T19:16:36.261Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_premise_formalization.sh 2 8002\\\"\", \"finished_at\": \"2026-05-18T19:19:15.214Z\", \"training_hours\": 0.04}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_premise_formalization.sh 2 8002\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:2\"], \"pid\": \"83150\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-042b-premise-formal.log\", \"submitted_at\": \"2026-05-18T19:16:37.520Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 159.8, \"gpu_hours\": 0.04}, \"pid\": \"83150\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-042b-premise-formal.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T19:19:17.277Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:19:19.962160+00:00\"}]}, \"notes\": \"失败根因：run_premise_formalization.sh 参数顺序是 PORT GPU，但调用传了 GPU PORT (2 8002)，导致 CUDA_VISIBLE_DEVICES=8002 → NVMLError_InvalidArgument。vLLM 未启动，0 题完成。将在 cleanup Worker 中用显式命令重部署。\"}, \"exp-044-icl-oracle\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:01:36.630Z\", \"updated_at\": \"2026-05-18T19:54:58.560Z\", \"hypothesis\": \"ICL with Oracle Examples: 用 5 个 gold FOL annotations 作为 few-shot examples 教 LLM 提取高质量约束。如果 extraction quality 是 capability trap 瓶颈，oracle-guided extraction 应能产生更 discriminative 的约束，使 ICL-SICA > vanilla SICA (74.51%)。评测 199 题（排除 5 个 ICL examples）。\", \"server\": \"westd-25068\", \"gpu\": \"cuda:0\", \"reproduce\": {\"server\": \"westd-25068\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-18T19:16:29.159Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_icl_oracle.sh 0 8000\\\"\", \"finished_at\": \"2026-05-18T19:52:18.717Z\", \"training_hours\": 0.6}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_icl_oracle.sh 0 8000\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:0\"], \"pid\": \"83086\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-044-icl-oracle.log\", \"submitted_at\": \"2026-05-18T19:16:30.455Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 2150.0, \"gpu_hours\": 0.6}, \"pid\": \"83086\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-044-icl-oracle.log\", \"conclusion\": \"failed\", \"notes\": \"v2 失败: vLLM server 连接中断 (httpx.ConnectError: All connection attempts failed)，EXIT_CODE=129 (SIGHUP)。实验跑完但数据无效：extraction 成功率仅 17.1% (307/1800, 1490 json_fail)，SC=46.23% 远低于 Qwen2.5-14B 预期 75.49%。结果不可用，需在 vLLM 稳定后重跑。worker_infra_westd25068-gpu-cleanup-redeploy 正在处理 westd-25068 基础设施。\", \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"completed_at\": \"2026-05-18T19:52:20.440Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:52:23.050199+00:00\"}]}}, \"exp-035\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:02:20.251Z\", \"updated_at\": \"2026-05-18T19:07:57.772Z\", \"hypothesis\": \"Qwen2.5-7B-Instruct 在 FOLIO-204 上 SICA vs SC：within-family scaling 下界验证。弱模型 C0 更高（更多 diversity），但 constraint quality 更差，SICA 仍无法 outperform SC。与 exp-004-qwen7b (D012 delta=0) 在 full FOLIO 上的扩展验证。代替原 ARC-60 实验（exp-035 v1 因平台 kill 失败）。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && CUDA_VISIBLE_DEVICES=3 VLLM_USE_FLASHINFER_SAMPLER=0 python -m vllm.entrypoints.openai.api_server --model /root/autodl-tmp/models/Qwen2.5-7B-Instruct --max-model-len 8192 --gpu-memory-utilization 0.90 --port 8003 --dtype auto --trust-remote-code --enforce-eager > /tmp/vllm_exp035.log 2>&1 & sleep 120 && python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8003/v1 --model auto --seed 42 --math-data data/empty.json --pw-data data/empty.json --folio-data data/folio_full.json --output results/exp035_qwen25_7b_folio204/exp035_results.json --save-intermediates 2>&1 | tee results/exp035_qwen25_7b_folio204/exp035.log\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:3\"], \"pid\": \"66133\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-035.log\", \"submitted_at\": \"2026-05-18T17:42:16.264Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 5136.9, \"gpu_hours\": 1.43}, \"conclusion\": \"negative\", \"notes\": \"v2 完成: Qwen2.5-7B FOLIO-204, 203/204题有结果(1题缺失)。JSON summary是stale的(n=195时计算)，实际数据从results数组203条计算。SICA与SC仅3个discordant pairs，几乎完全一致。假设验证：SICA无法outperform SC on 7B，delta=-0.49pp (p=1.0)。C0=0.55高于14B但未能转化为SICA优势。注意7B SC(77.34%)意外高于14B SC(75.49%)，可能因FOLIO数据特性。\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp035_qwen25_7b_folio204/exp035_results.json\", \"reproduce\": {\"finished_at\": \"2026-05-18T19:02:21.579Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:02:26.794237+00:00\"}]}, \"log_path\": \"~/runs/symb_invariant_consensus/exp-035.log\", \"metrics\": {\"n_problems\": 203, \"sc_accuracy\": 77.34, \"sica_accuracy\": 76.85, \"delta_pp\": -0.49, \"sica_correct\": 156, \"sc_correct\": 157, \"mcnemar_discordant_b\": 1, \"mcnemar_discordant_c\": 2, \"mcnemar_p_value\": 1, \"c0_non_unanimous_rate\": 0.5517, \"extraction_rate\": 98.19, \"contradiction_rate\": 1.58, \"problems_with_contradictions\": 60, \"total_constraints\": 12950, \"unique_constraints\": 6515, \"dedup_ratio\": 50.3, \"wall_time_min\": 78.2, \"avg_per_problem_s\": 23.1}, \"completed_at\": \"2026-05-18T19:07:53.139Z\"}, \"exp-036b-cross-trace-unsat\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:04:24.962Z\", \"updated_at\": \"2026-05-18T19:04:55.982Z\", \"hypothesis\": \"Cross-trace UNSAT: 合并不同候选答案的 constraints，检查 answer_A 与 answer_B 的约束是否 UNSAT（矛盾）。预期 cross-answer 对比的 UNSAT rate 远高于 within-trace 检查，因为不同答案的约束应该矛盾。如果 UNSAT 信号强，可用于增强 SICA 打分的 discriminative power。\", \"spec\": {\"command\": \"python3 cross_trace_unsat.py\", \"server\": \"westd-25068\", \"data_path\": \"results/folio_204_14b/\", \"data_count\": 204, \"model_name\": \"N/A (CPU-only, reuses exp-001 constraints)\", \"seed\": 42, \"checkpoint_source\": \"exp-001/folio_204_14b intermediates\", \"eval_data\": \"FOLIO-204\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp036b_cross_trace_unsat.json\", \"log_path\": \"/root/symb_invariant_consensus/results/exp036b_cross_trace_unsat.json\"}, \"conclusion\": \"negative\", \"metrics\": {\"cross_unsat_rate_pair\": 0.087, \"cross_unsat_rate_problem\": 0.107, \"within_trace_unsat_rate\": 0.009, \"unsat_pairs\": 11, \"total_pairs\": 126, \"problems_with_unsat\": 9, \"multi_answer_problems\": 84, \"single_answer_skip\": 120, \"zero_shared_var_pairs_pct\": 0.564, \"avg_shared_vars\": 2.7, \"false_true_unsat_rate\": 0.467, \"sica_cross_ut_accuracy\": 0.745, \"sc_accuracy\": 0.75, \"accuracy_impact\": 0}, \"completed_at\": \"2026-05-18T19:04:50.035Z\", \"notes\": \"Cross-trace UNSAT 验证了 Director 假设：cross-answer UNSAT rate (8.7%) 约为 within-trace (0.9%) 的 10x。但主要瓶颈是 Z3 变量命名不一致：56.4% 的 answer pairs 共享零变量，Z3 无法跨 trace 比较。False-True 对最具辨别力 (non-empty 中 46.7% UNSAT)。最终对准确率无影响（仅覆盖 9/204 问题），第 6 个 negative constructive。核心诊断价值：变量命名不一致是 capability trap 的关键机制之一。\"}, \"exp-042-premise-formalization\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:53:36.547Z\", \"updated_at\": \"2026-05-18T19:02:37.081Z\", \"hypothesis\": \"Premise-Only Formalization: 绕过 CoT trace extraction，直接让 LLM 将 FOLIO premises + conclusion 形式化为 FOL，用 Z3 验证逻辑蕴含。K=12 独立 formalization + majority vote。如果 extraction quality 是 capability trap 的瓶颈，直接 formalization 应能产生更准确的约束，使 Premise-FOL > vanilla SICA。\", \"spec\": {\"command\": \"premise_formalization.py --api-base http://localhost:8002/v1 --model auto --k 12 --data data/folio_full.json --output results/exp042_premise_formalization/results.json --seed 42\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:2\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-042-premise-formalization.log\", \"submitted_at\": \"2026-05-18T18:53:44.005Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct (cached)\", \"eval_data\": \"FOLIO-204\", \"wall_clock_seconds\": 533.1, \"gpu_hours\": 0.15}, \"reproduce\": {\"finished_at\": \"2026-05-18T19:02:34.758Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T19:02:37.081Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T19:02:40.161215+00:00\"}]}}, \"exp-043-consistency-filtering\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:58:40.028Z\", \"updated_at\": \"2026-05-18T18:59:10.069Z\", \"hypothesis\": \"Constraint Consistency Filtering: 从已有 exp-001 数据中，只保留在 ≥T/K 条 trace 中出现的约束（T=4,6,8），用筛选后的约束跑 MAX-SAT。假设跨 trace 一致出现的约束质量更高，filtered SICA > full SICA。\", \"spec\": {\"command\": \"python3 run_consistency_filtering.py\", \"server\": \"westd-25068\", \"data_path\": \"results/folio_204_14b/\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct (reuse exp-001 data)\", \"seed\": 42, \"checkpoint_source\": \"exp-001/folio_204_14b intermediates\", \"eval_data\": \"FOLIO-204\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp4_consistency_filtering/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp4_consistency_filtering/results.json\"}, \"conclusion\": \"negative\", \"metrics\": {\"sc_accuracy\": 0.75, \"sica_t1_all\": 0.7794, \"sica_t4\": 0.75, \"sica_t6\": 0.7549, \"sica_t8\": 0.7549, \"avg_unique_constraints\": 13.2, \"avg_filtered_t4\": 1.8, \"avg_filtered_t6\": 0.8, \"avg_filtered_t8\": 0.3}, \"completed_at\": \"2026-05-18T18:59:04.105Z\", \"notes\": \"Consistency filtering NEGATIVE: 过滤后约束数量骤降（T≥4 仅 1.8/题, T≥8 仅 0.3/题），MaxSAT 无法区分答案，退化为 SC。根因：Z3 变量命名不一致导致语义等价约束被视为不同（avg 13.2 unique constraints/problem），跨 trace 一致性极低。第 5 个 negative constructive intervention。注意：T=1 的 77.94% 与 exp-001 的 74.51% 差异是已知 pipeline 非确定性问题（code path confound）。\"}, \"exp-036-z3-feedback-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:18:09.052Z\", \"updated_at\": \"2026-05-18T18:53:05.656Z\", \"hypothesis\": \"Z3 UNSAT core feedback refinement: closed-loop 方法用 Z3 solver 的 UNSAT core 指导 LLM 修正矛盾约束（最多 3 轮）。如果约束质量是瓶颈，solver 反馈应能提升 constraint discriminative power，使 Z3-feedback SICA > vanilla SICA。目标 recovery_rate > 0%（recovery_rate = Z3fb_delta / oracle_delta × 100%）。与之前 open-loop interventions（contrastive/cross-model/generational 全部失败）对比，closed-loop 利用 formal verification 信号可能是打破 capability trap 的关键。\", \"spec\": {\"command\": \"python3 run_z3_feedback_folio.py --api-base http://localhost:8002/v1 --model auto --traces-dir results/folio_204_14b --max-rounds 3 --output-dir results/exp036_z3_feedback --K 12 --T-ext 0.3\", \"server\": \"westd-25068\", \"data_path\": \"results/folio_204_14b/\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"pre-computed traces from exp-001/folio_204_14b\", \"eval_data\": \"FOLIO-204\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp036_z3_feedback/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp036_z3_feedback/z3_feedback.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T18:52:57.206Z\", \"notes\": \"Z3 feedback mechanism had zero real impact. Apparent +3.0pp (77.5% vs 74.5%) entirely due to code path confound: JSON serialization vs in-memory processing caused different dedup/scoring behavior. UNSAT trigger rate 0.9% (22/2448 traces), too low for feedback loop to meaningfully activate. All observed delta on discordant problems came from pipeline non-determinism, not Z3 refinement. Fourth negative constructive intervention after contrastive, cross-model, generational.\", \"metrics\": {\"z3fb_sica_accuracy\": 0.775, \"vanilla_sica_accuracy\": 0.745, \"sc_accuracy\": 0.75, \"z3fb_vs_vanilla_delta\": 0.03, \"unsat_traces\": 22, \"total_traces\": 2448, \"unsat_rate\": 0.009, \"unsat_resolve_rate\": 0.864, \"problems_flipped\": 0, \"real_impact\": 0}}, \"exp-028-qwen3-14b-thinking\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:02:12.168Z\", \"updated_at\": \"2026-05-18T18:06:48.306Z\", \"hypothesis\": \"Qwen3-14B thinking mode 在 FOLIO 204 上 SICA vs SC：原生推理能力（内置 CoT）是否改变 capability trap？两种可能：(a) thinking mode 使 traces 更确定性（类似 QwQ-32B），C0 极低→SICA≡SC；(b) thinking mode 提升 constraint extraction 质量，打破 capability trap。预期 (a) 更可能。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash scripts/run_qwen3_14b_thinking.sh\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:2\"], \"pid\": \"40990\", \"log_path\": \"/root/symb_invariant_consensus/results/exp028_qwen3_14b_thinking/exp028.log\", \"submitted_at\": \"2026-05-18T14:21:40.871Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen3-14B (HuggingFace)\", \"eval_data\": \"FOLIO-204\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp028_qwen3_14b_thinking/\", \"wall_clock_seconds\": 13499.2, \"gpu_hours\": 3.75}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-18T18:06:40.098Z\", \"notes\": \"Killed per D049: extraction_rate 73% below 80% threshold. Partial results (35/204): SICA 88.57%, SC 85.71%, delta +2.86pp. But extraction_rate degrading and ETA 16h+ made continued run not worthwhile. GPU freed for D050 constructive experiments.\"}, \"exp-033-qwen3-pw600-nonthinking\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:01:55.209Z\", \"updated_at\": \"2026-05-18T18:00:09.156Z\", \"hypothesis\": \"Qwen3-14B in non-thinking mode on ProofWriter 600 will show whether SICA's constraint-based consensus improves over SC@K for a model without chain-of-thought reasoning overhead, providing a controlled comparison against thinking-mode results.\", \"spec\": {\"command\": \"bash scripts/run_exp033_qwen3_pw600.sh\", \"server\": \"westd-16639 (via westd-25068)\", \"data_path\": \"data/proofwriter_full.json\", \"data_count\": 600, \"model_name\": \"Qwen3-14B (non-thinking)\", \"seed\": 42, \"gpu\": \"cuda:1 (NVIDIA RTX PRO 6000 Blackwell 97GB)\", \"port\": 8001, \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 4096, \"max_model_len\": 8192, \"enable_thinking\": false, \"tmux_session\": \"exp033\", \"output_dir\": \"results/qwen3_14b_pw600_nonthinking/\", \"log_path\": \"results/qwen3_14b_pw600_nonthinking/run.log\"}, \"conclusion\": \"failed\", \"notes\": \"FAILED: AutoDL 平台级 SIGTERM 导致 vLLM EngineCore 崩溃 (00:05:54)，后紧急清理 Worker 误杀 tmux server 连带终止。518/600 intermediates 有效可恢复。\", \"checkpoint_path\": \"westd-16639:/root/symb_invariant_consensus/results/qwen3_14b_pw600_nonthinking/intermediates/ (518/600, instance reset lost)\", \"completed_at\": \"2026-05-18T18:00:09.156Z\"}, \"exp-004-qwen7b-rerun\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:16:48.010Z\", \"updated_at\": \"2026-05-18T18:00:08.383Z\", \"hypothesis\": \"Qwen2.5-7B-Instruct 在 D012 60 题上 SICA vs SC rerun（修复后代码）：弱模型 C0 更高（更多 diversity），但 constraint quality 更差，SICA 仍无法 outperform SC。验证 capability trap 在 within-family scaling 的下界。与之前 exp-004-qwen7b (delta=0) 对比验证一致性。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp004_7b_rerun.sh\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:3\"], \"pid\": \"58035\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-004-qwen7b-rerun.log\", \"submitted_at\": \"2026-05-18T16:30:26.795Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/folio_d012.json + data/proofwriter_d012.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-7B-Instruct\", \"eval_data\": \"D012 (30 FOLIO + 30 ProofWriter)\", \"wall_clock_seconds\": 5381.6, \"gpu_hours\": 1.49}, \"conclusion\": \"failed\", \"notes\": \"FAILED: ModelScope 下载失败，Qwen2.5-7B-Instruct 模型下载未完成。实验从未开始运行。需要 HF 镜像修复后重试。\", \"checkpoint_path\": \"N/A (download failed, never ran)\", \"completed_at\": \"2026-05-18T18:00:08.383Z\"}, \"exp-007-qwen72b-awq\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:16:47.099Z\", \"updated_at\": \"2026-05-18T18:00:07.574Z\", \"hypothesis\": \"Qwen2.5-72B-Instruct-AWQ (4-bit) 在 D012 60 题上 SICA vs SC：72B scaling 是否打破 capability trap？预期 SC baseline 更高（模型更强），但 SICA≈SC（extraction quality bottleneck 不随 model scale 改善），证明 scaling 不是 rescue path。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && bash /root/symb_invariant_consensus/scripts/run_exp007_72b_awq.sh\\\"\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:0\"], \"pid\": \"56225\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-007-qwen72b-awq.log\", \"submitted_at\": \"2026-05-18T16:21:30.961Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"D012 (30 FOLIO + 30 ProofWriter)\", \"data_count\": 60, \"model_name\": \"Qwen2.5-72B-Instruct-AWQ\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-72B-Instruct-AWQ (HuggingFace)\", \"eval_data\": \"D012 (30 FOLIO + 30 ProofWriter)\", \"wall_clock_seconds\": 5916.6, \"gpu_hours\": 1.64}, \"conclusion\": \"failed\", \"notes\": \"FAILED: HuggingFace 网络不通 (Network unreachable)，模型下载失败。72B AWQ 模型从未下载完成，实验从未开始运行。需要 HF 镜像修复后重试。\", \"checkpoint_path\": \"N/A (download failed, never ran)\", \"completed_at\": \"2026-05-18T18:00:07.575Z\"}, \"exp-027-qwen3-14b-non-thinking\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:02:11.425Z\", \"updated_at\": \"2026-05-18T17:58:11.787Z\", \"hypothesis\": \"Qwen3-14B（代际升级）在 non-thinking mode 下 FOLIO 204 的 SICA vs SC：capability trap 是否在次世代模型持续？预期 Qwen3 基础能力提升使 SC baseline 更高，但 self-extraction 质量仍不足以产生 SICA 增益（delta≈0），证明 capability trap 是结构性的而非模型能力不足。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_qwen3_14b_nonthinking.sh\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:1\"], \"pid\": \"38106\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-027-qwen3-14b-non-thinking.log\", \"submitted_at\": \"2026-05-18T14:08:01.969Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen3-14B\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen3-14B (HuggingFace)\", \"eval_data\": \"FOLIO-204\", \"wall_clock_seconds\": 13809.8, \"gpu_hours\": 3.84}, \"conclusion\": \"success\", \"metrics\": {\"n\": 204, \"k\": 12, \"sica_accuracy\": 0.8431, \"sc_accuracy\": 0.8382, \"delta_pp\": 0.49, \"extraction_rate\": 0.995, \"contradiction_rate\": 0.0283, \"problems_with_contradictions\": 69, \"total_constraints\": 16153, \"unique_constraints\": 7031, \"wall_time_s\": 11017, \"model\": \"Qwen3-14B\", \"dataset\": \"FOLIO-204\", \"mode\": \"non-thinking\"}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/qwen3_14b_folio204_nonthinking/\", \"notes\": \"Qwen3-14B non-thinking FOLIO-204: SICA 84.31% vs SC 83.82%, delta=+0.49pp。Qwen3 SC baseline 83.82% 远高于 Qwen2.5-14B 的 75.00% (+8.82pp)，证明 Qwen3 基础能力显著提升。但 SICA-SC gap 仍≈0 (+0.49pp)，capability trap 在次世代模型上持续。Extraction rate 99.5% (vs 14B 98.5%)，contradiction rate 2.83%。论文价值：(1) 证明 capability trap 是结构性的，非模型能力不足；(2) 代际升级提升 SC 不提升 SICA delta。\", \"completed_at\": \"2026-05-18T17:58:11.787Z\"}, \"exp-030-crossmodel-mistral-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:47:46.451Z\", \"updated_at\": \"2026-05-18T16:16:11.345Z\", \"hypothesis\": \"Cross-model extraction: Mistral-7B 从 Qwen2.5-14B 的 FOLIO 204 traces 中提取 constraints，能否打破 same-model capability trap？不同模型有不同的 extraction bias，Mistral 可能提取出 Qwen self-extraction 遗漏的 discriminative constraints。目标 discriminative_rate >8.2%（baseline），recovery_rate >0%。\", \"parent\": \"exp-026-folio204-trace-regen\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp030_crossmodel_mistral.sh\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:0\"], \"pid\": \"46525\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-030-crossmodel-mistral-folio204.log\", \"submitted_at\": \"2026-05-18T14:50:47.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/results/folio_204_14b/intermediates/\", \"data_count\": 204, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"exp-026-folio204-trace-regen\", \"eval_data\": \"FOLIO-204\", \"wall_clock_seconds\": 5123.4, \"gpu_hours\": 1.42}, \"conclusion\": \"negative\", \"metrics\": {\"n\": 204, \"k\": 12, \"crossmodel_sica_accuracy\": 0.75, \"sc_accuracy\": 0.75, \"delta_pp\": 0, \"discriminative_rate\": 0, \"recovery_rate\": 0, \"model_extraction\": \"Mistral-7B-Instruct-v0.3\", \"model_traces\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"FOLIO-204\"}, \"notes\": \"NEGATIVE. Cross-model extraction (Mistral-7B extracts constraints from Qwen2.5-14B traces) 完全无效：SICA = SC = 75.00%, discriminative_rate=0%, recovery_rate=0%. Mistral 虽然是不同模型家族，但提取的 constraints 同样缺乏判别力。这进一步强化 capability trap 结论：问题不在 same-model bias，而在 LLM extraction 本身的能力限制——无论哪个模型做 extraction，都无法从 CoT traces 中提取出对答案有判别力的 symbolic constraints。论文 claim: cross-model 不是 rescue path。\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/cross_model_mistral_folio/\", \"completed_at\": \"2026-05-18T16:16:11.345Z\"}, \"exp-031-oracle-folio-regen\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:48:41.292Z\", \"updated_at\": \"2026-05-18T15:55:28.070Z\", \"hypothesis\": \"Oracle SICA with gold FOL annotations on exp-026 regenerated traces (post normalization-fix): if constraint quality is the bottleneck, replacing self-extracted constraints with gold FOL + Z3 entailment should significantly outperform SC and SICA(self), replicating exp-021's finding on fixed code.\", \"spec\": {\"command\": \"python scripts/run_exp031_oracle_folio_regen.py\", \"server\": \"westd-25068\", \"data_path\": \"data/folio_full.json + results/folio_204_14b/intermediates/\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct (traces) + Z3 (oracle constraints)\", \"seed\": 42, \"checkpoint_path\": \"results/oracle_folio_regen/exp031_results.json\", \"log_path\": \"results/oracle_folio_regen/exp031_summary.json\"}, \"conclusion\": \"success\", \"metrics\": {\"n\": 204, \"k\": 12, \"oracle_sica_accuracy\": 0.8971, \"sc_accuracy\": 0.7549, \"sica_self_accuracy\": 0.7451, \"oracle_vs_sc_delta_pp\": 14.22, \"oracle_vs_sica_delta_pp\": 15.2, \"mcnemar_p_oracle_vs_sc\": 2.0024e-07, \"mcnemar_b_c\": {\"b_oracle_right_sc_wrong\": 29, \"c_oracle_wrong_sc_right\": 0}, \"z3_gold_agreement\": 0.951, \"z3_gold_agree_n\": 194, \"z3_in_candidates_n\": 178, \"fol_parse_success\": 1, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"FOLIO-204\", \"constraint_source\": \"gold FOL annotations\", \"traces_source\": \"exp-026-folio204-trace-regen\"}, \"completed_at\": \"2026-05-18T15:49:32.164Z\", \"notes\": \"KEY RESULT. Oracle-SICA (gold FOL + Z3 entailment + consistency-weighted voting) 89.71% vs SC 75.49% vs SICA(self) 74.51%, +14.22pp over SC, McNemar p=2.0e-07 极显著, b=29 c=0 (oracle 从未输给 SC)。Z3 gold agreement 95.10% (194/204), FOL parser 204/204 全成功。Per-type: True 97.2% (+4.1pp), False 93.6% (+6.3pp), Unknown 78.3% (+31.9pp)。与 exp-021 (88.24%, 旧 traces) 对比：oracle 准确率从 88.24% 提升至 89.71%（+1.47pp），delta 从 +8.82pp 增至 +14.22pp。差异来源：(1) exp-026 traces 的 SC baseline 更低 (75.49% vs 79.41%)；(2) Z3 agreement 从 94.6% 提升至 95.1%。结论与 exp-021 一致：MAX-SAT 聚合机制有效——瓶颈在约束提取质量。\"}, \"exp-029-contrastive-folio204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:22:03.513Z\", \"updated_at\": \"2026-05-18T15:38:58.925Z\", \"hypothesis\": \"Contrastive constraint extraction (answer-conditioned supporting/opposing constraints with structured JSON output and MaxSAT integration) will achieve discriminative_rate >20% (vs baseline 8.2%) and positive recovery_rate on FOLIO 204, because per-candidate opposing constraints provide stronger signal than simple majority voting for disambiguating closely-scored answers.\", \"parent\": \"exp-026-folio204-trace-regen\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && bash /root/symb_invariant_consensus/scripts/run_exp029_contrastive.sh'\", \"server\": \"westd-25068\", \"gpu\": [\"cuda:3\"], \"pid\": \"42353\", \"log_path\": \"/root/symb_invariant_consensus/results/exp-029-contrastive-folio204/run.log\", \"submitted_at\": \"2026-05-18T14:24:26.683Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/results/folio_204_14b/intermediates/\", \"data_count\": 181, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"exp-026-folio204-trace-regen\", \"eval_data\": \"FOLIO-204\", \"wall_clock_seconds\": 4354.6, \"gpu_hours\": 1.21, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp-029-contrastive-folio204/contrastive_results.json\"}, \"conclusion\": \"negative\", \"checkpoint_path\": \"results/exp-029-contrastive-folio204/contrastive_results.json\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-029-contrastive-folio204.log\", \"completed_at\": \"2026-05-18T15:37:01.319Z\", \"metrics\": {\"contrastive_accuracy\": 0.7253, \"sc_accuracy\": 0.7363, \"delta_pp\": -1.1, \"discriminative_rate\": 0.0604, \"discriminative_count\": 11, \"n\": 182, \"recovery_rate_pct\": -8.3, \"mcnemar_chi2\": 0.1, \"mcnemar_p\": 0.7518, \"cont_only_correct\": 4, \"sc_only_correct\": 6, \"both_correct\": 128, \"both_wrong\": 44, \"supporting_pct\": 43.2, \"opposing_pct\": 56.8, \"avg_constraints_per_problem\": 24.4, \"avg_unique_per_problem\": 10.4, \"wall_time_min\": 47.2}}, \"exp-026-folio204-trace-regen\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-18T11:41:13.054Z\", \"updated_at\": \"2026-05-18T14:46:34.862Z\", \"hypothesis\": \"FOLIO 204 全量 trace 重生成（Qwen2.5-14B, K=12, T=0.7 trace gen, T_ext=0.3 extraction）：在 westd-25068 上生成 FOLIO traces，用于 cross-model extraction 和 case study 选取。归一化 bug 已修复（startswith 方案），温度双参数已正确分离。\", \"parent\": \"sica_expanded_14b\", \"reproduce\": {\"finished_at\": \"2026-05-18T12:07:33.628Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-18T12:07:34.444Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T12:07:37.428043+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"bash scripts/run_folio_trace_regen.sh\", \"server\": \"westd-25068\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_full.json\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"gpu_ids\": [\"cuda:0\"], \"pid\": 27245, \"log_path\": \"/root/symb_invariant_consensus/logs/folio_regen_v3_20260518_201127.log\", \"output_path\": \"/root/symb_invariant_consensus/results/folio_204_14b/folio_204_results.json\", \"temperature_trace\": 0.7, \"temperature_extraction\": 0.3, \"K\": 12, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct (HuggingFace)\", \"eval_data\": \"FOLIO-204 validation set\"}, \"conclusion\": \"success\", \"metrics\": {\"n\": 204, \"k\": 12, \"sica_accuracy\": 0.7451, \"sc_accuracy\": 0.7549, \"delta_pp\": -0.98, \"extraction_rate\": 0.9853, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"FOLIO-204\", \"temperature_trace\": 0.7, \"temperature_extraction\": 0.3, \"wall_time_h\": 2.5}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/folio_204_14b/\", \"notes\": \"FOLIO 204 全量 trace 重生成完成 (204/204)。SICA 74.51% vs SC 75.00%, delta=-0.49pp，与 sica_expanded_14b FOLIO 子集 (79.4%/79.4%, delta=0) 一致——capability trap 在重生成 traces 上仍成立。归一化 bug 修复 + 温度双参数分离后 extraction_rate=98.53% (vs 之前 89%)。Traces 已被 exp-029 contrastive 实验复用。结果路径: /root/symb_invariant_consensus/results/folio_204_14b/folio_204_results.json\"}, \"exp-023-discriminative-rate\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T03:50:26.792Z\", \"updated_at\": \"2026-05-18T04:44:24.397Z\", \"hypothesis\": \"Full-dataset discriminative rate analysis (W1+W3 合并): Qwen2.5-14B 在 804 题上 self-extracted constraints 的 source-trace discriminativeness 和 Z3 semantic discriminativeness 均低于 15%，证明即使用 Z3 per-answer evaluation，self-extracted constraints 仍无判别力，封堵 oracle scoring confound。\", \"parent\": \"sica_constraint_ablation_013\", \"spec\": {\"command\": \"python scripts/analyze_discriminative_rate.py\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/results/sica_expanded_14b.json\", \"data_count\": 804, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": \"N/A\", \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"/root/symb_invariant_consensus/results/discriminative_rate_analysis.json\", \"checkpoint_source\": \"sica_expanded_14b traces\", \"eval_data\": \"FOLIO 204 + ProofWriter 600 = 804\"}, \"metrics\": {\"n_total\": 804, \"n_multi_candidate\": 307, \"source_disc_rate_weight\": 0.392, \"source_disc_rate_weight_ci95\": [0.387, 0.398], \"source_disc_rate_count_est\": 0.121, \"source_disc_rate_count_ci95\": [0.12, 0.123], \"z3_semantic_disc_rate\": 0.082, \"z3_semantic_disc_ci95\": [0.076, 0.088], \"problems_with_disc\": 289, \"problems_with_disc_rate\": 0.941, \"pw_source_disc_weight\": 0.364, \"folio_source_disc_weight\": 0.54, \"pw_n_multi\": 235, \"folio_n_multi\": 72, \"pilot_rate_reported_count\": 0.115, \"pilot_rate_reported_weight\": 0.372, \"pilot_validation_weight\": 0.376, \"pilot_delta_pp\": 0.38, \"z3_answer_assertions\": 642, \"z3_total_unique_constraints\": 7844, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"FOLIO+ProofWriter-804\"}, \"conclusion\": \"success\", \"notes\": \"Full 804-instance discriminative rate (R3 W1+W3, v1+v2 合并). By weight: 39.2% [38.7, 39.8]; by count (est): 12.1% [12.0, 12.3]. Z3 semantic disc: 8.2% [7.6, 8.8]. Per-domain: FOLIO 54.0% > PW 36.4% (by weight). 289/307 multi-candidate 问题有≥1 discriminative constraint (94.1%). Pilot validation: weight 37.6% vs 报告 37.2% (delta 0.38pp); count 12.1% vs 报告 11.5% (delta 0.6pp)——高度一致。v2 修复了 v1 的 assertion weight 不对称问题。数据: /root/symb_invariant_consensus/analysis/discriminative_rate_full_804.json\", \"completed_at\": \"2026-05-18T04:25:57.741Z\"}, \"exp-022-oracle-proofwriter\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T03:47:31.892Z\", \"updated_at\": \"2026-05-18T03:48:13.174Z\", \"hypothesis\": \"ProofWriter oracle: gold DSL (raw_logic_programs) 通过 Z3 consistency checking 加权 K=12 traces，Oracle-SICA 应显著超越 SC 和 SICA(self)，在 ProofWriter 600 题上复现 FOLIO oracle (+8.82pp) 的 extraction bottleneck 结论。\", \"parent\": \"exp-021-oracle-folio\", \"spec\": {\"command\": \"python scripts/run_exp022_oracle_proofwriter.py\", \"server\": \"westd-32608\", \"data_path\": \"/root/autodl-tmp/crdd/data/proofwriter/proofwriter-OWA-D5-validation.jsonl\", \"data_count\": 600, \"model_name\": \"Qwen2.5-14B-Instruct (traces) + Z3 (oracle)\", \"seed\": \"N/A\", \"checkpoint_path\": \"N/A (CPU-only oracle)\", \"log_path\": \"/root/symb_invariant_consensus/results/exp022_oracle_pw.log\", \"checkpoint_source\": \"sica_expanded_14b traces (no model checkpoint)\", \"eval_data\": \"ProofWriter OWA-D5 validation 600 problems\"}, \"conclusion\": \"success\", \"metrics\": {\"n\": 600, \"k\": 12, \"oracle_sica_accuracy\": 0.8667, \"sc_accuracy\": 0.7517, \"sica_self_accuracy\": 0.755, \"oracle_vs_sc_delta_pp\": 11.5, \"mcnemar_p_oracle_vs_sc\": 9.21e-15, \"z3_gold_agreement\": 0.9714, \"z3_gold_agree_n\": 577, \"z3_gold_total\": 594, \"parse_errors\": 6, \"parse_error_rate\": 0.01, \"solver_errors\": 0, \"solver_total\": 7128, \"relneg_oracle\": 0.7786, \"relneg_sc\": 0.6, \"relneg_delta_pp\": 17.86, \"relnoneg_oracle\": 0.7945, \"relnoneg_sc\": 0.6644, \"relnoneg_delta_pp\": 13.01, \"attnoneg_oracle\": 0.961, \"attnoneg_sc\": 0.8701, \"attnoneg_delta_pp\": 9.09, \"attneg_oracle\": 0.9188, \"attneg_sc\": 0.85, \"attneg_delta_pp\": 6.87, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"ProofWriter-OWA-D5-600\", \"constraint_source\": \"gold DSL (raw_logic_programs)\"}, \"notes\": \"KEY RESULT. ProofWriter Oracle-SICA (gold DSL + Z3 + MAX-SAT) 86.67% vs SC 75.17% vs SICA(self) 75.50%, +11.50pp, McNemar p=9.21e-15 极显著。Z3 gold agreement 97.14% (577/594), parse errors 仅 6/600 (1%), solver errors 0/7128。Per-subtype: RelNeg +17.86pp > RelNoneg +13.01pp > AttNoneg +9.09pp > AttNeg +6.87pp——关系谓词（推理链更长）获益远大于属性谓词。与 FOLIO oracle (exp-021, +8.82pp, p=6.15e-5) 对比：ProofWriter delta 更大 (+11.50 vs +8.82) 且统计显著性高 6 个数量级。两个子域 Oracle 实验一致证明：MAX-SAT 聚合机制有效，瓶颈在 LLM self-extraction 质量。\", \"completed_at\": \"2026-05-18T03:48:13.174Z\"}, \"temperature-ablation-t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:03:05.890Z\", \"updated_at\": \"2026-05-17T19:11:20.157Z\", \"hypothesis\": \"Temperature ablation T=0.7 同源补跑：消除 T=0.7 数据来自不同 run (sica_d012_14b) 的混淆。预期 Δ=0（与 T=0.3/0.5/1.0 一致），C0 值可直接与其他温度点比较。\", \"parent\": \"temperature-ablation-t03\", \"spec\": {\"command\": \"bash /root/autodl-tmp/symb_invariant_consensus/scripts/run_temperature_ablation_t07.sh\", \"server\": \"westd-32608\", \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:0\", \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"D012 (30 ProofWriter + 30 FOLIO)\", \"tmux_session\": \"temperature-ablation-t07\"}, \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.7167, \"sc_accuracy\": 0.75, \"delta_pp\": -3.33, \"multi_candidate_rate\": 0.4, \"extraction_rate\": 0.9208, \"answer_extraction_rate\": 1, \"contradiction_rate\": 0.022, \"discordant_sica_wins\": 0, \"discordant_sc_wins\": 2, \"truncated_traces\": 0, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"D012\", \"temperature\": 0.7, \"proofwriter_sica\": 0.6333, \"proofwriter_sc\": 0.7, \"proofwriter_n\": 30, \"folio_sica\": 0.8, \"folio_sc\": 0.8, \"folio_n\": 30, \"wall_time_s\": 3498.3}, \"notes\": \"T=0.7 同源补跑完成（60/60 题）。C0=40.0%，介于 T=0.5(38.3%) 和 T=1.0(43.3%) 之间，消除了旧数据 T=0.7(53.3%) 来自不同 run 的混淆。四温度点 C0 现呈单调递增：T=0.3(30%) → T=0.5(38.3%) → T=0.7(40.0%) → T=1.0(43.3%)。SICA 71.67% < SC 75.00%，delta=-3.33pp，discordant 0:2（SC wins only）。FOLIO 80%=80%，PW SICA 63.33% < SC 70%。结论与其他温度点一致：diversity 增加但 constraint quality 无改善，delta≈0。\", \"conclusion\": \"negative\", \"log_path\": \"/root/runs/symb_invariant_consensus/sica_aime30_t07.log\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/temperature_ablation/temperature_ablation_T0.7_results.json\", \"completed_at\": \"2026-05-17T19:11:20.157Z\"}, \"sica_constraint_ablation_013\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T20:26:35.414Z\", \"updated_at\": \"2026-05-17T18:38:00.543Z\", \"spec\": {\"command\": \"python scripts/extract_constraints_for_ablation.py\", \"server\": \"westd-32608\", \"data_path\": \"results/sica_expanded_14b/\", \"data_count\": 804, \"model_name\": \"N/A (CPU ablation on exp-001 outputs)\", \"seed\": \"N/A\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"log_path\": \"results/constraint_ablation.json\", \"completed_at\": \"2026-05-16T20:26:58.473Z\", \"hypothesis\": \"exp-013: MaxSAT 加权聚合是否比 count-only 或 random-weight 有显著优势？验证 SICA 核心机制（约束加权）的实际贡献\", \"parent\": \"sica_expanded_14b\", \"metrics\": {\"maxsat_accuracy\": 0.7649, \"count_only_accuracy\": 0.7662, \"random_weight_accuracy\": 0.7587, \"sc_baseline_accuracy\": 0.7624, \"n_problems\": 804, \"maxsat_correct\": 615, \"count_only_correct\": 616, \"random_weight_correct\": 610, \"sc_correct\": 613, \"agreement_maxsat_vs_countonly\": \"803/804\", \"agreement_maxsat_vs_randomwt\": \"785/804\", \"agreement_maxsat_vs_sc\": \"773/804\", \"agreement_countonly_vs_randomwt\": \"786/804\", \"agreement_countonly_vs_sc\": \"774/804\", \"agreement_randomwt_vs_sc\": \"764/804\", \"mcnemar_p_all_gt_0.7\": true}, \"notes\": \"exp-013 constraint ablation 完成，数据已从 ablation_results.json 交叉验证。关键修正：(1) 802/804 不存在于任何 pairwise comparison，原 registry 数据错误；(2) random-weight accuracy 修正为 75.87% (610/804)，原 76.37% 是近似值。核心发现：MaxSAT vs Count-only 803/804 agreement 确认 SAT solver 无增量。MaxSAT vs SC 773/804 (31 disagreements, 16 SICA wins / 14 SC wins / 1 both wrong diff)——SICA 改了 31 题但 wins/losses 几乎抵消。数据文件：/root/symb_invariant_consensus/analysis/exp013_agreement_matrix.json\"}, \"exp-004-qwen7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T17:09:36.912Z\", \"updated_at\": \"2026-05-17T18:10:04.422Z\", \"hypothesis\": \"Within-family scaling: Qwen2.5-7B-Instruct 在 D012 60 题上 SICA vs SC。弱模型预期 C0 > 14B（更多 diversity），但 constraint quality 预期更低，SICA-SC gap 预期≈0——验证 capability trap 的 scaling 维度。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp004_qwen7b.sh\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/data/\", \"data_count\": 60, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:0\", \"tmux_session\": \"exp-004-qwen7b\", \"checkpoint_source\": \"Qwen/Qwen2.5-7B-Instruct (base pretrained, symlink at /root/autodl-tmp/models/Qwen2.5-7B-Instruct)\", \"eval_data\": \"D012 (30 ProofWriter + 30 FOLIO)\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T17:55:15.007Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T17:55:15.926Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T17:55:18.762977+00:00\"}]}, \"notes\": \"Qwen2.5-7B within-family scaling: SICA=SC=68.33% (41/60), Δ=0.00pp, C0=43.3%, McNemar p=1.0。60 题全部完成（run.log 确认）。C0=43.3% 高于 14B 的 38.2%（弱模型更多 diversity），但 Δ=0 确认 capability trap 在 7B scale 同样成立。Discordant 2:2 完全对称。Per-domain: FOLIO SICA 76.7% vs SC 73.3% (+3.3pp), PW SICA 60.0% vs SC 63.3% (-3.3pp)，方向相反互相抵消。extraction_rate=94.2%。\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.6833, \"sc_accuracy\": 0.6833, \"delta_pp\": 0, \"multi_candidate_rate\": 0.433, \"extraction_rate\": 0.9417, \"answer_extraction_rate\": 1, \"contradiction_rate\": 0.0274, \"discordant_sica_wins\": 2, \"discordant_sc_wins\": 2, \"mcnemar_p\": 1, \"wall_time_s\": 1838, \"truncated_traces\": 0, \"model\": \"Qwen2.5-7B-Instruct\", \"dataset\": \"D012\", \"temperature\": 0.7, \"folio_sica\": 0.7667, \"folio_sc\": 0.7333, \"folio_n\": 30, \"proofwriter_sica\": 0.6, \"proofwriter_sc\": 0.6333, \"proofwriter_n\": 30}}, \"temperature-ablation-t10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:46:01.069Z\", \"updated_at\": \"2026-05-17T17:16:54.736Z\", \"hypothesis\": \"Temperature ablation T=1.0: 高温下 Qwen2.5-14B trace diversity 最大化（C0 预期>60%），SICA-SC gap 预期≈0 或负——验证最大 diversity 仍不能拯救 SICA，因为 constraint discriminative power 不随 diversity 增加\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash scripts/run_temperature_ablation.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"D012 (30 ProofWriter + 30 FOLIO)\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/temperature_ablation/temperature_ablation_T1.0_results.json\", \"log_path\": \"/tmp/temperature_ablation.log\"}, \"notes\": \"T=1.0 高温：C0=43.3%，低于 T=0.7 的 53.3%（注意：T=0.7 数据来自 sica_d012_14b 不同 run）。SICA=SC=75.00%，delta=0，discordant=0。最大温度仍不能拯救 SICA。Temperature ablation 结论：T=0.3(30%) → T=0.5(38.3%) → T=1.0(43.3%) 三点 C0 递增，但加上 T=0.7(53.3%, 来自 sica_d012_14b) 后整体非单调（T=0.7 > T=1.0）。不同 run 间 C0 有随机波动。核心结论不变：delta 始终=0，diversity 不是瓶颈。\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.75, \"sc_accuracy\": 0.75, \"delta_pp\": 0, \"multi_candidate_rate\": 0.433, \"discordant_total\": 0, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"D012\", \"temperature\": 1}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T16:47:11.985Z\"}, \"exp-012-gsm8k-pilot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T16:47:20.559Z\", \"updated_at\": \"2026-05-17T17:09:35.283Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 GSM8K (开放答案数学域) 30 题上 SICA vs SC。预期 C0<20%（14B 在 GSM8K 太强），验证 C0 作为 SICA 无效性预测指标。\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash scripts/run_exp012_gsm8k.sh\", \"server\": \"westd-32608\", \"data_path\": \"data/gsm8k_200.json\", \"data_count\": 30, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen2.5-14B-Instruct\", \"eval_data\": \"data/gsm8k_200.json\", \"gpu\": [\"cuda:0\"], \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp012_gsm8k/\", \"log_path\": \"/root/symb_invariant_consensus/results/exp012_gsm8k/\"}, \"metrics\": {\"n\": 30, \"k\": 12, \"sica_accuracy\": 0.9667, \"sc_accuracy\": 0.9667, \"delta_pp\": 0, \"multi_candidate_rate\": 0.133, \"extraction_success_rate\": 0.147, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"GSM8K\", \"temperature\": 0.7}, \"conclusion\": \"negative\", \"notes\": \"GSM8K 30题：SICA=SC=96.67%，delta=0，C0=13.3%。开放答案数学域 baseline 极高（96.67%），几乎无 diversity（C0=13.3%），extraction_success_rate 仅 14.7%——数学域的 symbolic constraints 难以提取。支持 C0 作为 SICA 无效性预测指标。\", \"completed_at\": \"2026-05-17T17:09:35.283Z\"}, \"exp-021-oracle-folio\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T16:36:04.545Z\", \"updated_at\": \"2026-05-17T16:48:21.295Z\", \"hypothesis\": \"If we replace self-extracted constraints with gold FOL annotations verified by Z3, Oracle-SICA should significantly outperform both SC and SICA, demonstrating that constraint quality is the bottleneck for SICA gains on formal logic tasks.\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"python scripts/run_exp021_oracle_folio.py\", \"server\": \"westd-32608\", \"data_path\": \"data/folio_full.json + results/sica_expanded_14b.json\", \"data_count\": 204, \"model_name\": \"Qwen2.5-14B-Instruct (traces) + Z3 (oracle constraints)\", \"seed\": 42, \"checkpoint_path\": \"results/exp021_oracle_folio/exp021_results.json\", \"log_path\": \"results/exp021_oracle_folio/exp021_summary.json\", \"checkpoint_source\": \"results/sica_expanded_14b.json\", \"eval_data\": \"data/folio_full.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T16:45:52.280Z\", \"metrics\": {\"n\": 204, \"k\": 12, \"oracle_sica_accuracy\": 0.8824, \"sc_accuracy\": 0.7941, \"sica_self_accuracy\": 0.7941, \"oracle_vs_sc_delta_pp\": 8.82, \"oracle_vs_sica_delta_pp\": 8.82, \"mcnemar_p_oracle_vs_sc\": 6.15e-05, \"z3_gold_agreement\": 0.946, \"fol_parse_success\": 1, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"FOLIO-204\", \"constraint_source\": \"gold FOL annotations\"}, \"notes\": \"KEY RESULT. Oracle-SICA (gold FOL + Z3 consistency check + MAX-SAT) 88.24% vs SC 79.41% vs SICA(self-extracted) 79.41%, +8.82pp, McNemar p=6.15e-05 高度显著。Z3 solver 与 gold answer 一致率 94.6%（193/204），FOL parser 204/204 全部成功。SICA(self)=SC 确认 LLM 自提取约束在 formal logic 上无有效信号。结论：MAX-SAT 聚合机制本身有效——瓶颈在约束提取质量，不在聚合算法。这直接回答了 Reviewer 的核心 confound 质疑。\"}, \"temperature-ablation-t05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:45:59.468Z\", \"updated_at\": \"2026-05-17T16:47:09.843Z\", \"hypothesis\": \"Temperature ablation T=0.5: 中温下 Qwen2.5-14B trace diversity 中等（C0 预期 30-45%），SICA-SC gap 预期≈0——验证即使 diversity 适中，constraint quality 仍为瓶颈\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash scripts/run_temperature_ablation.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"D012 (30 ProofWriter + 30 FOLIO)\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/temperature_ablation/temperature_ablation_T0.5_results.json\", \"log_path\": \"/tmp/temperature_ablation.log\"}, \"notes\": \"T=0.5 中温：C0=38.3%，SICA=SC=76.67%，delta=0，discordant=0。中等 diversity 下 SICA 仍完全等于 SC。\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.7667, \"sc_accuracy\": 0.7667, \"delta_pp\": 0, \"multi_candidate_rate\": 0.383, \"discordant_total\": 0, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"D012\", \"temperature\": 0.5}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T16:47:09.843Z\"}, \"temperature-ablation-t03\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:45:57.395Z\", \"updated_at\": \"2026-05-17T16:47:07.935Z\", \"hypothesis\": \"Temperature ablation T=0.3: 低温下 Qwen2.5-14B trace diversity 降低（C0 预期<30%），SICA-SC gap 预期≈0——验证 diversity 不足时 SICA 无操作空间，capability trap 的下界\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash scripts/run_temperature_ablation.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"eval_data\": \"D012 (30 ProofWriter + 30 FOLIO)\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/temperature_ablation/temperature_ablation_T0.3_results.json\", \"log_path\": \"/tmp/temperature_ablation.log\"}, \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.7333, \"sc_accuracy\": 0.7333, \"delta_pp\": 0, \"multi_candidate_rate\": 0.3, \"discordant_total\": 0, \"model\": \"Qwen2.5-14B-Instruct\", \"dataset\": \"D012\", \"temperature\": 0.3}, \"conclusion\": \"negative\", \"notes\": \"T=0.3 低温：C0=30%（符合预期低于 T=0.7 的 53%），SICA=SC=73.33%，delta=0，discordant=0。低温降低 diversity 但 SICA 无任何改变——约束完全无判别力。\", \"completed_at\": \"2026-05-17T16:47:07.935Z\"}, \"exp-014-deepseek-r1-7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:52:10.748Z\", \"updated_at\": \"2026-05-17T13:43:42.275Z\", \"hypothesis\": \"DeepSeek-R1-Distill-Qwen-7B（reasoning distill 模型）在 D012 上 SICA vs SC——预期 C0<5%（类似 QwQ-32B，reasoning model 的确定性链消灭多样性），作为第二个 reasoning model 数据点验证 capability trap\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp014_deepseek_r1_7b.sh\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": 324400, \"log_path\": \"~/runs/symb_invariant_consensus/exp-014-deepseek-r1-7b.log\", \"submitted_at\": \"2026-05-17T11:52:19.117Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/data/\", \"data_count\": 60, \"model_name\": \"DeepSeek-R1-Distill-Qwen-7B\", \"seed\": 42, \"checkpoint_source\": \"HuggingFace deepseek-ai/DeepSeek-R1-Distill-Qwen-7B\", \"eval_data\": \"D012 (30PW+30FOLIO)\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp014_deepseek_r1_7b/exp014_results.json\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T13:34:23.083Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T13:34:24.985786+00:00\"}]}, \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.6833, \"sc_accuracy\": 0.7167, \"delta_pp\": -3.33, \"multi_candidate_rate\": 0.583, \"extraction_rate\": 0.839, \"answer_extraction_rate\": 0.939, \"truncated_traces\": 72, \"contradiction_rate\": 0.037, \"wall_time_min\": 100.3, \"mcnemar_p\": 0.4795, \"discordant_sica_wins\": 0, \"discordant_sc_wins\": 2, \"model\": \"DeepSeek-R1-Distill-Qwen-7B\", \"dataset\": \"D012\"}, \"conclusion\": \"negative\", \"notes\": \"假设预判错误：预期 C0<5%（类似 QwQ-32B reasoning model），实际 C0=58.3%。DeepSeek-R1-Distill-Qwen-7B 因 7B 容量不足以维持确定性推理链，表现为 instruction-scale model。SICA -3.3pp，两子域对称（FOLIO -3.3pp, PW -3.3pp）。重新定位为第四个 instruction-scale 模型验证 capability trap。\", \"completed_at\": \"2026-05-17T13:42:50.983Z\"}, \"exp-010-mistral-v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T06:48:05.255Z\", \"updated_at\": \"2026-05-17T13:39:59.922Z\", \"hypothesis\": \"Cross-family validation: Mistral-7B-Instruct-v0.3 在 D012 数据集(30PW+30FOLIO)上是否复现 SICA≈SC pattern——验证 capability trap 跨模型家族泛化（v3: 脚本内含 vLLM 清理+conda 环境，解决 v2 SIGTERM 问题）\", \"parent\": \"sica_expanded_14b\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp010_mistral.sh\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"298717\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-010-mistral-v3.log\", \"submitted_at\": \"2026-05-17T07:56:55.973Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"D012 (30 ProofWriter + 30 FOLIO)\", \"data_count\": 60, \"model_name\": \"Mistral-7B-Instruct-v0.3\", \"seed\": 42, \"checkpoint_source\": \"huggingface:mistralai/Mistral-7B-Instruct-v0.3\", \"eval_data\": \"ProofWriter-D5 + FOLIO (D012 split)\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp010_mistral_v3/\", \"wall_clock_seconds\": 1506.4, \"gpu_hours\": 0.42}, \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"reproduce\": {\"finished_at\": \"2026-05-17T08:17:39.965Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T08:17:42.415004+00:00\"}]}, \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.4833, \"sc_accuracy\": 0.4833, \"delta_pp\": 0, \"multi_candidate_rate\": 0.5, \"extraction_rate\": 0.8819, \"answer_extraction_rate\": 1, \"contradiction_rate\": 0.0562, \"discordant_sica_wins\": 2, \"discordant_sc_wins\": 2, \"mcnemar_p\": 1, \"proofwriter_sica\": 0.4, \"proofwriter_sc\": 0.4, \"proofwriter_delta_pp\": 0, \"folio_sica\": 0.5667, \"folio_sc\": 0.5667, \"folio_delta_pp\": 0, \"truncated_traces\": 0, \"model\": \"Mistral-7B-Instruct-v0.3\", \"dataset\": \"D012\"}, \"conclusion\": \"negative\", \"notes\": \"Mistral-7B cross-family: SICA 48.33% = SC 48.33%, delta=0.00pp。Multi-candidate rate 50%（30/60 题非 unanimous），SICA 仅改变 4 题（6.67% flip rate）。模型太弱：SC baseline 48.33%（近随机），trace 缺乏质量但有多样性。Discordant 2:2 平局，McNemar p=1.0。支持 operating regime 有下界：模型必须足够强才能生成有意义的 diverse traces。PW 40%/40%, FOLIO 56.67%/56.67%。\", \"completed_at\": \"2026-05-17T08:22:02.386Z\"}, \"sica_expanded_14b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T05:12:00.374Z\", \"updated_at\": \"2026-05-17T13:26:43.835Z\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --pw-data data/proofwriter_full.json --folio-data data/folio_full.json --math-data data/empty.json --output results/sica_expanded_14b.json --save-intermediates\", \"server\": \"westd-32608\", \"data_path\": \"data/proofwriter_full.json (600 D5) + data/folio_full.json (204)\", \"data_count\": 804, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"pid\": \"181491\", \"gpu\": [\"cuda:0\"], \"log_path\": \"~/runs/symb_invariant_consensus/sica_expanded_14b.log\", \"submitted_at\": \"2026-05-16T05:19:00.966Z\", \"backend\": \"nohup\", \"account\": \"root\", \"eta_hours\": 13.4, \"wall_clock_seconds\": 50368.9, \"gpu_hours\": 13.99}, \"reproduce\": {\"finished_at\": \"2026-05-16T19:18:29.155Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T19:18:29.888Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T19:18:30.703230+00:00\"}]}, \"metrics\": {\"sica_accuracy\": 0.765, \"sc_accuracy\": 0.762, \"sica_sc_gap_pp\": 0.3, \"n_problems\": 804, \"multi_candidate_rate\": 0.3818, \"folio_sica\": 0.794, \"folio_sc\": 0.794, \"folio_gap_pp\": 0, \"folio_n\": 204, \"proofwriter_sica\": 0.755, \"proofwriter_sc\": 0.752, \"proofwriter_gap_pp\": 0.3, \"proofwriter_n\": 600, \"extraction_rate\": 0.89, \"answer_extraction_rate\": 1, \"contradiction_rate\": 0.022, \"problems_with_contradictions\": 331, \"truncated_traces\": 0, \"wall_time_min\": 826}, \"notes\": \"实验完整完成 804/804 题并保存结果。EXIT_CODE=129 是 SIGHUP 伪信号（进程退出阶段收到），非真实失败。日志末尾打印 \\\"FULL_MVP_DONE\\\" 后才出现 exit code。D025 pivot 确认：SICA≈SC (+0.3pp, N=804)，D012 +3.3pp 是小样本噪声。FOLIO sub-claim dead (0pp)。\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/sica_expanded_14b.json\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 N=804 (600PW+204FOLIO) 上 SICA 相比 SC 有统计显著优势（p<0.05）——full-scale validation of D012 preliminary +3.3pp signal\", \"parent\": \"sica_d012_14b\"}, \"exp-019-llama8b-strategyqa-200\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T08:07:01.919Z\", \"updated_at\": \"2026-05-17T13:26:41.871Z\", \"hypothesis\": \"Powered test: SICA 在弱模型（LLaMA-3.1-8B）上的增益在 n=200 StrategyQA 题时达到统计显著（p<0.05）——验证 operating regime 假设（D031 + exp-011 directionally positive +6.67pp）\", \"parent\": \"exp-011-llama8b-v3\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T08:18:21.546Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp019_strategyqa_200.sh\\\"\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T09:10:18.592Z\", \"training_hours\": 0.87}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp019_strategyqa_200.sh\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"302372\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-019-llama8b-strategyqa-200.log\", \"submitted_at\": \"2026-05-17T08:18:24.001Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp019_strategyqa_200/\", \"wall_clock_seconds\": 3450.0, \"gpu_hours\": 0.96}, \"pid\": \"302372\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-019-llama8b-strategyqa-200.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T09:10:21.404482+00:00\"}]}, \"metrics\": {\"n\": 200, \"k\": 12, \"sica_accuracy\": 0.74, \"sc_accuracy\": 0.72, \"delta_pp\": 2, \"multi_candidate_rate\": 0.41, \"mcnemar_p\": 0.424, \"bootstrap_ci_95\": [-1.5, 5.5], \"bootstrap_p_delta_le_0\": 0.12, \"discordant_sica_wins\": 9, \"discordant_sc_wins\": 5, \"discordant_total\": 14, \"discordant_rate\": 0.07, \"sc_unanimous_rate\": 0.545, \"model\": \"LLaMA-3.1-8B-Instruct\", \"dataset\": \"StrategyQA\", \"wall_time_min\": 52}, \"conclusion\": \"negative\", \"notes\": \"StrategyQA 200题 powered test: SICA 74% vs SC 72%, +2.00pp, McNemar p=0.424, bootstrap CI [-1.5, +5.5] 跨零。统计不显著。exp-011 的 +6.67pp 在扩大样本后缩水 70%——小样本噪声。关键发现：(1) LLaMA-8B 在 StrategyQA 上 SC=72%，高于预期的 sweet spot (55-65%)，(2) 仅 14/200 (7%) discordant pairs，54.5% 全票一致，(3) SICA 仅充当 tiebreaker（9 wins 中 6 个是平票）。StrategyQA 不在 operating regime sweet spot 内。exp-020 FOLIO (SC≈60%) 是真正的 definitive test。\", \"completed_at\": \"2026-05-17T09:15:53.996Z\"}, \"exp-018-arc-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T06:13:27.054Z\", \"updated_at\": \"2026-05-17T13:26:39.502Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 ARC-Challenge (科学多选, ABCD) 上 SICA vs SC——验证 capability trap 是否跨任务类型泛化（v2: build_generator bug 已修复）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T06:19:18.377Z\", \"command\": \"cd /root/symb_invariant_consensus && bash scripts/run_exp018_arc.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T06:39:42.063Z\", \"training_hours\": 0.34}, \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && bash scripts/run_exp018_arc.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"289541\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-018-arc-v2.log\", \"submitted_at\": \"2026-05-17T06:19:19.350Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1433.8, \"gpu_hours\": 0.4}, \"pid\": \"289541\", \"log_path\": \"/root/symb_invariant_consensus/results/exp018_arc/exp018_results.json\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T06:39:44.088518+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.95, \"sc_accuracy\": 0.9667, \"delta_pp\": -1.67, \"multi_candidate_rate\": 0.05, \"extraction_rate\": 1, \"contradiction_detected\": 3, \"discordant_sica_wins\": 0, \"discordant_sc_wins\": 1, \"dataset\": \"ARC-Challenge\", \"model\": \"Qwen2.5-14B-Instruct\"}, \"notes\": \"ARC-Challenge cross-domain: SICA 95.00% vs SC 96.67%, gap=-1.67pp. SICA 略逊于 SC。模型在 ARC 上 baseline 极高(96.67%)，接近天花板——高准确率区间多样性低，SICA 无操作空间。与 StrategyQA (+3.33pp n.s.) 对比：简单任务（高 baseline）SICA 无效或有害，中等难度任务有微弱正向趋势但不显著。整体支持 capability trap：模型能力越强/任务越简单 → SC 已近最优 → SICA 无增量。\", \"checkpoint_path\": \"N/A (evaluation experiment)\", \"completed_at\": \"2026-05-17T06:43:13.130Z\"}, \"exp-009-overhead-analysis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:51:43.293Z\", \"updated_at\": \"2026-05-17T12:01:08.521Z\", \"hypothesis\": \"SICA pipeline 的 wall-time overhead breakdown: trace generation vs constraint extraction vs MaxSAT solving 各占多少——量化 SICA 相对 SC 的额外计算成本\", \"metrics\": {\"n\": 804, \"mean_total_wall_s\": 61.6, \"mean_trace_gen_s\": 31.6, \"trace_gen_pct\": 51.3, \"mean_extract_s\": 29, \"extract_pct\": 47, \"mean_dedup_s\": 1, \"dedup_pct\": 1.6, \"mean_maxsat_s\": 0.003, \"maxsat_pct\": 0.005, \"sica_overhead_s\": 30, \"sica_overhead_pct\": 48.7, \"pw_overhead_pct\": 51.3, \"folio_overhead_pct\": 38.6, \"p50_overhead_pct\": 48.9, \"p90_overhead_pct\": 57.6}, \"conclusion\": \"success\", \"notes\": \"SICA overhead 分析 (804题)：总时间 61.6s/题，其中 trace 生成 31.6s (51.3%)，约束提取 29.0s (47.0%)，去重 1.0s (1.6%)，MaxSAT 0.003s (≈0%)。SICA vs SC 多花 30.0s/题 (+48.7%)，开销几乎全部来自 constraint extraction LLM 调用。MaxSAT 求解可忽略。论文 insight：SICA 的计算瓶颈不在 formal reasoning (SAT) 而在 LLM extraction，且 extraction 产出的约束缺乏判别力——高成本低回报。\", \"spec\": {\"command\": \"CPU-only analysis of exp-001 timing data\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/results/\", \"data_count\": 804, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42}, \"checkpoint_path\": \"N/A (CPU-only analysis)\", \"log_path\": \"N/A (CPU-only analysis)\", \"completed_at\": \"2026-05-17T12:01:08.521Z\"}, \"exp-020-llama8b-folio-204\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T08:12:49.897Z\", \"updated_at\": \"2026-05-17T11:50:57.467Z\", \"hypothesis\": \"Powered FOLIO test: SICA 在弱模型（LLaMA-3.1-8B）上 FOLIO 全量 204 题是否达到统计显著——FOLIO 在 exp-011 中信号最强（+10pp, bootstrap p≈0.04），n=204 几乎必然显著。保险实验：若 StrategyQA discordant rate 低导致 underpowered。\", \"parent\": \"exp-011-llama8b-v3\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp020_folio_200.sh\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"309318\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-020-llama8b-folio-204.log\", \"submitted_at\": \"2026-05-17T09:12:58.789Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_204.jsonl\", \"data_count\": 204, \"model_name\": \"meta-llama/Llama-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_source\": \"N/A (inference-only, no checkpoint)\", \"eval_data\": \"FOLIO full dataset 204 problems\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp020_folio_200/\", \"wall_clock_seconds\": 9478.7, \"gpu_hours\": 2.63}, \"reproduce\": {\"finished_at\": \"2026-05-17T11:27:04.546Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T11:27:06.717657+00:00\"}]}, \"metrics\": {\"n\": 204, \"k\": 12, \"sica_accuracy\": 0.608, \"sc_accuracy\": 0.632, \"delta_pp\": -2.45, \"mcnemar_p\": 0.2668, \"bootstrap_ci_95\": [-5.88, 0.98], \"bootstrap_p_sica_ge_sc\": 0.1, \"discordant_sica_wins\": 4, \"discordant_sc_wins\": 9, \"discordant_total\": 13, \"discordant_rate\": 0.064, \"multi_candidate_rate\": 0.618, \"extraction_rate\": 0.942, \"answer_extraction_rate\": 0.951, \"contradiction_rate\": 0.062, \"both_wrong\": 71, \"model\": \"LLaMA-3.1-8B-Instruct\", \"dataset\": \"FOLIO-204\", \"wall_time_min\": 131.7}, \"conclusion\": \"negative\", \"notes\": \"DEFINITIVE NEGATIVE。LLaMA-8B FOLIO 204题：SICA 60.8% vs SC 63.2%, delta=-2.45pp, McNemar p=0.2668, CI [-5.88, +0.98]。Discordant 4:9 SICA 输多赢少。exp-011 FOLIO +10pp 在 n=204 完全反转为 -2.45pp——确认为 Type I error (n=30 随机波动)。C0=61.8% 高（SICA 有操作空间），但约束改票时反而引入更多错误(9 SC wins vs 4 SICA wins)。Sweet spot hypothesis 被否定。SICA≤SC everywhere 确认。\", \"completed_at\": \"2026-05-17T11:50:57.467Z\"}, \"pilot-contrastive-prompt\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T06:18:22.559Z\", \"updated_at\": \"2026-05-17T08:02:40.938Z\", \"hypothesis\": \"Contrastive Prompt Extraction: 将 prompt 改为\\\"列出支持答案X/反对答案Y的证据\\\"能否将 discriminative ratio 从 37.2% 提升至 >70%，并使 SICA(contrastive) > SC ≥3pp——验证 answer-conditioned 约束是否解决 SICA 机制 vacuous 问题\", \"parent\": \"pilot-constraint-filtering\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T06:42:48.028Z\", \"command\": \"cd /root/symb_invariant_consensus && python scripts/pilot_contrastive_constraints.py\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T06:43:15.557Z\", \"training_hours\": 0.01}, \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && python scripts/pilot_contrastive_constraints.py\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/pilot-contrastive-prompt.log\", \"submitted_at\": \"2026-05-17T06:42:49.646Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 26.8, \"gpu_hours\": 0.01}, \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/pilot-contrastive-prompt.log\", \"failure_reason\": \"EXIT_CODE=127 (command not found — check bash -c wrapping / env activate)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T06:43:16.479Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T06:43:18.090519+00:00\"}]}, \"notes\": \"脚本已验证可用（run_pilot_contrastive_v2.sh + pilot_contrastive_constraints.py）。修复方案：submit 时用 bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && bash /root/symb_invariant_consensus/scripts/run_pilot_contrastive_v2.sh\\\" 包裹。当前 GPU 被 exp-010-mistral-v3 占用（vLLM 87880MiB），等其完成后提交。\"}, \"exp-011-llama8b-v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T06:15:02.161Z\", \"updated_at\": \"2026-05-17T07:59:02.260Z\", \"hypothesis\": \"Cross-family validation: LLaMA-3.1-8B-Instruct 在 D012 数据集(30PW+30FOLIO)上是否复现 SICA≈SC pattern——验证 capability trap 非 Qwen-specific（v3: 模型 shard 已修复，GPU 空闲后提交）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T06:45:47.789Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp011_llama8b.sh\\\"\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T07:55:14.227Z\", \"training_hours\": 1.16}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && bash scripts/run_exp011_llama8b.sh\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"292780\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b-v3.log\", \"submitted_at\": \"2026-05-17T06:45:49.636Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4392.6, \"gpu_hours\": 1.22}, \"pid\": \"292780\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b-v3.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T07:55:16.092007+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.6667, \"sc_accuracy\": 0.6, \"delta_pp\": 6.67, \"multi_candidate_rate\": 0.6167, \"extraction_rate\": 0.8556, \"answer_extraction_rate\": 0.8958, \"contradiction_rate\": 0.0527, \"problems_with_contradictions\": 43, \"truncated_traces\": 44, \"discordant_sica_wins\": 5, \"discordant_sc_wins\": 1, \"mcnemar_p\": 0.2188, \"proofwriter_sica\": 0.6333, \"proofwriter_sc\": 0.6, \"proofwriter_delta_pp\": 3.33, \"folio_sica\": 0.7, \"folio_sc\": 0.6, \"folio_delta_pp\": 10, \"model\": \"LLaMA-3.1-8B-Instruct\", \"dataset\": \"D012\", \"wall_time_min\": 66.4}, \"notes\": \"LLaMA-3.1-8B cross-family: SICA 66.7% vs SC 60.0%, +6.67pp (最大增益)。Discordant 5:1 强烈倾向 SICA。FOLIO +10pp, PW +3.33pp。McNemar p=0.22（n=60 受限）。Multi-candidate rate 61.7%（vs Qwen-14B 46%）——弱模型更多样→SICA 有更大操作空间。44 条 truncated traces（max-tokens 可能偏短），但仍有效。关键：SC baseline 60%（远低于 Qwen-14B 的 76%），验证 capability trap 的正面——模型弱时 SICA 有用。\", \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp011_llama8b/exp011_results.json\", \"completed_at\": \"2026-05-17T07:59:02.260Z\"}, \"exp-010-mistral-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:26:42.201Z\", \"updated_at\": \"2026-05-17T06:19:34.268Z\", \"hypothesis\": \"Cross-family validation: Mistral-7B-Instruct-v0.3 在 D012 数据集(30PW+30FOLIO)上是否复现 SICA≈SC pattern——验证 capability trap 跨模型家族泛化（v2: 修复 max-model-len=8192 防 400 循环）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T05:51:38.846Z\", \"command\": \"pkill -f \\\"vllm.entrypoints\\\" 2>/dev/null; sleep 3; cd /root/symb_invariant_consensus && bash scripts/run_exp010_mistral.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T05:51:53.254Z\", \"training_hours\": 0.0}, \"spec\": {\"command\": \"pkill -f \\\"vllm.entrypoints\\\" 2>/dev/null; sleep 3; cd /root/symb_invariant_consensus && bash scripts/run_exp010_mistral.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-010-mistral-v2.log\", \"submitted_at\": \"2026-05-17T05:51:40.607Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 13.6, \"gpu_hours\": 0.0}, \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-010-mistral-v2.log\", \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T05:51:54.213Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T05:51:55.875957+00:00\"}]}, \"notes\": \"SIGTERM (exit 143) 在提交后 ~15s。根因：compound command 中 pkill -f \\\"vllm.entrypoints\\\" 可能误杀 tmux 父进程链。Director 已明确禁止 pkill 和 bash 脚本写在同一行。需要 v3：先手动清理 vLLM，再独立提交脚本。\"}, \"pilot-constraint-filtering\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T04:47:05.171Z\", \"updated_at\": \"2026-05-17T06:11:36.503Z\", \"hypothesis\": \"Constraint Consistency Filtering: 只保留在≥T条traces中重复出现的约束能否提升SICA accuracy超过SC——验证约束质量过滤是否解决capability trap\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T04:47:13.762Z\", \"command\": \"cd /root/symb_invariant_consensus && bash scripts/run_pilot_constraint_filtering.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T05:28:15.355Z\", \"training_hours\": 0.68}, \"spec\": {\"command\": \"cd /root/symb_invariant_consensus && bash scripts/run_pilot_constraint_filtering.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"282213\", \"log_path\": \"~/runs/symb_invariant_consensus/pilot-constraint-filtering.log\", \"submitted_at\": \"2026-05-17T04:47:15.480Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 5013.4, \"gpu_hours\": 1.39}, \"pid\": \"282213\", \"log_path\": \"~/runs/symb_invariant_consensus/pilot-constraint-filtering.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T05:28:16.989563+00:00\"}]}, \"conclusion\": \"negative\", \"notes\": \"NEGATIVE confirmed. T=1/2/3 结果完全一致(+2.33pp=1题翻转), T≥5 SICA退化为SC。Discriminative analysis: unique constraints 中 11.5% 是 discriminative (by count), 37.2% (by weight)。但有效 flip 率仅 4/23=17.4%。根本原因：提取的约束是 domain facts (kind_charlie==True, Implies(...)) — 无论答案是什么，中间推理步骤大部分共通。约束系统未提取答案级别判别谓词。Constraint filtering 天花板极低，不是 rescue path。\", \"checkpoint_path\": \"N/A (analysis experiment, no checkpoint)\", \"completed_at\": \"2026-05-17T06:10:48.874Z\", \"metrics\": {\"n\": 43, \"thresholds_tested\": [1, 2, 3, 5, 7], \"best_gap_pp\": 2.33, \"best_T\": 1, \"sica_T1\": 0.7674, \"sc\": 0.7442, \"T5_gap\": 0, \"T7_gap\": 0, \"discriminative_ratio_count\": 0.115, \"discriminative_ratio_weight\": 0.372, \"effective_flip_rate\": 0.174, \"multi_answer_problems\": 23, \"unanimous_problems\": 20, \"problems_disc_favors_different\": 4}}, \"exp-018-arc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:19:51.591Z\", \"updated_at\": \"2026-05-17T05:31:46.070Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 ARC-Challenge (科学多选, ABCD) 上 SICA vs SC——验证 capability trap 是否跨任务类型泛化（多选题型）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T05:30:39.347Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp018_arc.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T05:30:48.403Z\", \"training_hours\": 0.0}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp018_arc.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"285496\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-018-arc.log\", \"submitted_at\": \"2026-05-17T05:30:41.118Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 8.2, \"gpu_hours\": 0.0}, \"pid\": \"285496\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-018-arc.log\", \"failure_reason\": \"Traceback → al_arc.py\\\", line 244, in &lt;module> main() File \\\"/root/symb_invariant_consensus/scripts/eval_arc.py\\\", line 142, in main generator = build_generator(args) ^^^^^^^^^^^^^^^ NameError: name 'build_generator' is not defined. Did you mean: 'build_extractor'?\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T05:30:49.360Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T05:30:50.922842+00:00\"}]}, \"notes\": \"NameError: name 'build_generator' is not defined in eval_arc.py:142. 代码bug——函数未定义/未导入。Worker 诊断修复中。\"}, \"exp-017-strategyqa-v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T04:17:54.931Z\", \"updated_at\": \"2026-05-17T05:29:12.136Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 StrategyQA (常识推理, Yes/No) 上 SICA vs SC——验证 capability trap 是否跨任务类型泛化（v3: 修复 True/False→Yes/No 提取 bug）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T04:18:02.638Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T04:26:23.412Z\", \"training_hours\": 0.14}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"278827\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa-v3.log\", \"submitted_at\": \"2026-05-17T04:18:04.451Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4267.7, \"gpu_hours\": 1.19}, \"pid\": \"278827\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa-v3.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T04:26:25.041303+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"n\": 60, \"k\": 12, \"sica_accuracy\": 0.5667, \"sc_accuracy\": 0.5333, \"delta_pp\": 3.33, \"mcnemar_chi2\": 0.5, \"mcnemar_p\": \"n.s.\", \"bootstrap_ci_95\": [0, 8.33], \"bootstrap_p_delta_le_0\": 0.1346, \"multi_candidate_rate\": 0.1, \"contradiction_detected\": 5, \"extraction_rate_problem\": 1, \"extraction_rate_trace\": 0.704, \"discordant_sica_wins\": 2, \"discordant_sc_wins\": 0}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/exp017_strategyqa/exp017_results.json\", \"notes\": \"StrategyQA跨域验证: SICA 56.67% vs SC 53.33%, +3.33pp n.s. (p=0.13), 支持capability trap跨任务泛化; v3修复提取bug确认成功(100%问题级提取率); 2个discordant pairs均SICA胜出\", \"completed_at\": \"2026-05-17T05:29:12.136Z\"}, \"exp-017-strategyqa-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:50:55.005Z\", \"updated_at\": \"2026-05-17T04:27:27.997Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 StrategyQA (常识推理, Yes/No) 上 SICA vs SC——验证 capability trap 是否跨任务类型泛化（非逻辑/数学域）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T03:51:02.300Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T04:01:13.600Z\", \"training_hours\": 0.17}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"274312\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa-v2.log\", \"submitted_at\": \"2026-05-17T03:51:04.002Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 2184.0, \"gpu_hours\": 0.61}, \"pid\": \"274312\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa-v2.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T04:01:15.665453+00:00\"}]}, \"conclusion\": \"failed\", \"failure_reason\": \"答案提取bug: 73.3% (44/60) answer=\\\"\\\"。Pipeline输出True/False但extractor只认Yes/No。数据无效，需修复后重跑。\", \"completed_at\": \"2026-05-17T04:27:27.997Z\"}, \"exp-017-strategyqa\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:19:50.628Z\", \"updated_at\": \"2026-05-17T03:50:54.370Z\", \"hypothesis\": \"Cross-domain validation: Qwen2.5-14B-Instruct 在 StrategyQA (常识推理, Yes/No) 上 SICA vs SC——验证 capability trap 是否跨任务类型泛化（非逻辑/数学域）\", \"parent\": \"sica_expanded_14b\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T03:46:30.089Z\", \"command\": \"pkill -f vllm 2>/dev/null || true; sleep 2; bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T03:47:02.948Z\", \"training_hours\": 0.01}, \"spec\": {\"command\": \"pkill -f vllm 2>/dev/null || true; sleep 2; bash /root/symb_invariant_consensus/scripts/run_exp017_strategyqa.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa.log\", \"submitted_at\": \"2026-05-17T03:46:31.684Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 32.2, \"gpu_hours\": 0.01}, \"pid\": \"unknown\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-017-strategyqa.log\", \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T03:47:03.842Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T03:47:05.693732+00:00\"}]}}, \"exp-010-mistral\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T01:04:36.900Z\", \"updated_at\": \"2026-05-17T03:37:29.439Z\", \"hypothesis\": \"Cross-family validation: Mistral-7B-Instruct-v0.3 在 D012 数据集上是否复现 SICA≈SC pattern——验证 capability trap 跨模型家族泛化\", \"parent\": \"sica_expanded_14b\", \"notes\": \"模型已确认完整下载：3 shards (4.95+5.00+4.55GB) + consolidated.safetensors (14.5GB)。排在 exp-018 之后启动。需要 Worker 准备启动脚本（参照 exp-011 模式）。\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T03:22:52.734Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp010_mistral.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T03:37:29.116Z\", \"training_hours\": 0.24}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp010_mistral.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"270100\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-010-mistral.log\", \"submitted_at\": \"2026-05-17T03:22:54.245Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 875.2, \"gpu_hours\": 0.24}, \"pid\": \"270100\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-010-mistral.log\", \"conclusion\": \"failed\", \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-17T03:37:29.439Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T03:37:31.206441+00:00\"}]}}, \"exp-011-llama8b-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:19:49.625Z\", \"updated_at\": \"2026-05-17T03:24:54.392Z\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T03:19:59.814Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp011_llama8b.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T03:22:16.279Z\", \"training_hours\": 0.04}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp011_llama8b.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"269123\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b-v2.log\", \"submitted_at\": \"2026-05-17T03:20:01.559Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 135.6, \"gpu_hours\": 0.04}, \"pid\": \"269123\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b-v2.log\", \"hypothesis\": \"Cross-family validation: LLaMA-3.1-8B-Instruct 在 D012 数据集(30PW+30FOLIO)上是否复现 SICA≈SC pattern——验证 capability trap 非 Qwen-specific (v2: 修复 GPU OOM，kill 旧 vLLM 后重跑)\", \"parent\": \"sica_expanded_14b\", \"failure_reason\": \"模型权重损坏: model-00002-of-00004.safetensors 下载不完整 (3.7G vs 预期 ~4.9G)，safetensors_rust.SafetensorError\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T03:22:17.134Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T03:22:18.620317+00:00\"}]}}, \"sica_temp_diversity\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:14:34.555Z\", \"updated_at\": \"2026-05-17T03:21:14.807Z\", \"spec\": {\"command\": \"python3 diagnose_diversity.py\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/data/math500_subset.json\", \"data_count\": 5, \"model_name\": \"QwQ-32B\", \"seed\": 42, \"method\": \"SICA-diagnostic\", \"checkpoint_path\": \"N/A\", \"log_path\": \"/root/symb_invariant_consensus/results/diversity_diagnosis.json\"}, \"hypothesis\": \"不同 temperature (0.7/0.9/1.0) 下 QwQ-32B 是否产生足够的 trace 分歧以触发 MAX-SAT 矛盾检测\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T12:14:56.903Z\", \"metrics\": {\"temperatures_tested\": [0.7, 0.9, 1], \"problems_tested\": 3, \"problems_with_divergence\": 0, \"finding\": \"QwQ-32B produces zero answer divergence at all temperatures on MATH L4-5. Reasoning model's deterministic chain dominates sampling randomness.\", \"max_tokens_issue\": \"4096 tokens insufficient for some L5 problems (truncation)\", \"recommendation\": \"Use AIME 2024 (harder, ~79.5% acc) or non-reasoning model for trace diversity\"}, \"parent\": \"sica_smoke_5q\"}, \"sica_d012_14b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:02:41.309Z\", \"updated_at\": \"2026-05-17T03:21:14.256Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/symb_invariant_consensus && CUDA_VISIBLE_DEVICES=0 python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --math-data /tmp/empty_math.json --pw-data data/proofwriter_30.json --folio-data data/folio_30.json --output results/sica_d012_14b.json --save-intermediates 2>&1 | tee /tmp/sica_d012_14b.log\\\"\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"177178\", \"log_path\": \"~/runs/symb_invariant_consensus/sica_d012_14b.log\", \"submitted_at\": \"2026-05-16T04:05:23.888Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"wall_clock_seconds\": 3809.2, \"gpu_hours\": 1.06}, \"reproduce\": {\"finished_at\": \"2026-05-16T05:04:49.668Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T05:04:50.574652+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"sica_accuracy\": 0.7333, \"sc_accuracy\": 0.7, \"sica_sc_gap_pp\": 3.3, \"c0_multi_candidate_rate\": 0.5333, \"c1_extraction_rate\": 1, \"c2_contradiction_problems\": 34, \"c3_gap_pp\": 3.3, \"bootstrap_p\": 0.2261, \"proofwriter_sica\": 0.6667, \"proofwriter_sc\": 0.6667, \"folio_sica\": 0.8, \"folio_sc\": 0.7333, \"total_constraints_raw\": 5849, \"total_constraints_unique\": 1735, \"maxsat_exclusion_rate\": 0.0259, \"wall_time_min\": 58.3, \"d012_verdict\": \"ALL_PASS\"}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/sica_d012_14b.json\", \"completed_at\": \"2026-05-16T05:08:53.052Z\", \"hypothesis\": \"Qwen2.5-14B-Instruct 在 D012 (30PW+30FOLIO) 上 SICA pipeline 端到端有效：C0(多候选率≥20%) + C1(提取率≥80%) + C2(矛盾率≥10%) + C3(SICA>SC) 四项 sanity check 全通过\", \"parent\": \"sica_d016_c0_precheck\"}, \"sica_k_sensitivity_14b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T05:12:03.025Z\", \"updated_at\": \"2026-05-17T03:19:48.625Z\", \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_k_ablation.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"237939\", \"log_path\": \"~/runs/symb_invariant_consensus/sica_k_sensitivity_14b.log\", \"submitted_at\": \"2026-05-16T20:00:54Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_30.json + data/folio_30.json\", \"data_count\": 60, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"k_values\": [6, 8, 11, 12, 16, 20], \"eta_hours\": 5.9, \"checkpoint_source\": \"Qwen2.5-14B-Instruct (base, no fine-tuning)\", \"eval_data\": \"D012 60 problems (PW30+FOLIO30)\", \"wall_clock_seconds\": 22151.7, \"gpu_hours\": 6.15}, \"hypothesis\": \"K-ablation: K={6,8,11,12,16,20} 对 SICA 效果的影响。K=11(奇数)无平票，若 gap=0 则证明 SICA 仅靠 tiebreak 生效\", \"parent\": \"sica_expanded_14b\", \"reproduce\": {\"finished_at\": \"2026-05-17T02:10:05.417Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T02:10:05.719Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T02:10:07.161307+00:00\"}]}, \"metrics\": {\"K6_sica\": 0.733, \"K6_sc\": 0.733, \"K6_gap_pp\": 0, \"K8_sica\": 0.733, \"K8_sc\": 0.75, \"K8_gap_pp\": -1.7, \"K11_sica\": 0.733, \"K11_sc\": 0.733, \"K11_gap_pp\": 0, \"K12_sica\": 0.7, \"K12_sc\": 0.75, \"K12_gap_pp\": -5, \"K16_sica\": 0.717, \"K16_sc\": 0.75, \"K16_gap_pp\": -3.3, \"K20_sica\": 0.7, \"K20_sc\": 0.733, \"K20_gap_pp\": -3.3, \"all_K_sica_leq_sc\": true, \"larger_K_degrades_sica\": true}, \"notes\": \"K-ablation 实际完成（EXIT_CODE=129 为 SIGHUP 假失败，同 sica_expanded_14b 模式）。结果：SICA ≤ SC for all K。K=11(奇数)验证 tiebreak 无贡献(gap=0)。K=12/16/20 SICA 退化 -3~5pp，表明更多 traces 引入更多低质量约束反而有害。直接强化 C1 (mechanism vacuous)。Artifact: art_20260517_2c1577。\"}, \"exp-011-llama8b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T01:00:32.450Z\", \"updated_at\": \"2026-05-17T03:00:35.641Z\", \"hypothesis\": \"Cross-family validation: LLaMA-3.1-8B-Instruct 在 D012 数据集(30PW+30FOLIO)上是否复现 SICA≈SC pattern——验证 capability trap 非 Qwen-specific\", \"parent\": \"sica_expanded_14b\", \"notes\": \"Prep done by worker_prep_exp-011-llama8b_20260516T204635. Model: LLaMA-3.1-8B-Instruct (14GB, 4 shards). Script: /root/symb_invariant_consensus/scripts/run_exp011_llama8b.sh. Dataset: D012 (30 PW + 30 FOLIO = 60 题). 预估 ~25-30GB GPU, ~1-1.5h runtime. 等 sica_k_sensitivity_14b 完成后启动。\", \"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-32608\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T02:56:05.600Z\", \"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp011_llama8b.sh\", \"code_commit\": \"97aeaa572a6b6571b4bfea9c6ec6bcf915780425\", \"finished_at\": \"2026-05-17T02:58:40.441Z\", \"training_hours\": 0.04}, \"spec\": {\"command\": \"bash /root/symb_invariant_consensus/scripts/run_exp011_llama8b.sh\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"266576\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b.log\", \"submitted_at\": \"2026-05-17T02:56:07.282Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 154.1, \"gpu_hours\": 0.04}, \"pid\": \"266576\", \"log_path\": \"~/runs/symb_invariant_consensus/exp-011-llama8b.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T02:58:41.363Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T02:58:43.037174+00:00\"}]}}, \"exp-016-weighted-sc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T01:01:51.841Z\", \"updated_at\": \"2026-05-17T01:02:16.162Z\", \"hypothesis\": \"加权投票变体(inverse-length/length-weighted/constraint-count)是否比 uniform SC 有统计显著优势——验证简单启发式能否替代 SICA 或超越 SC\", \"parent\": \"sica_expanded_14b\", \"conclusion\": \"success\", \"metrics\": {\"sica_accuracy\": 0.7649, \"sc_uniform_accuracy\": 0.7624, \"inv_length_accuracy\": 0.7674, \"length_weighted_accuracy\": 0.7525, \"constraint_count_accuracy\": 0.7525, \"inv_length_vs_sc_p\": 0.453, \"length_vs_sc_p\": 0.153, \"inv_length_vs_sica_p\": 0.864, \"length_vs_sica_p\": 0.066, \"n_problems\": 804, \"all_nonsignificant\": true}, \"notes\": \"exp-016 weighted SC baselines 完成。804题上所有加权变体 vs SC/SICA 均不显著(p>0.05)。Length-weighting 反而 -1pp（长 trace 略不可靠），inv-length +0.5pp 但非显著。结论：简单启发式加权不能替代也不能超越 uniform voting。支持 C1 (mechanism vacuous) — 问题不在聚合方式，而在约束质量本身。Artifacts: art_20260516_c7cc07 (report), art_20260516_7eef43 (data).\", \"spec\": {\"checkpoint_path\": \"N/A (analysis on existing traces)\", \"log_path\": \"N/A\", \"command\": \"python scripts/weighted_sc_baseline.py\", \"server\": \"westd-32608\", \"data_path\": \"exp-001 traces (804 problems)\", \"data_count\": 804, \"model_name\": \"Qwen2.5-14B-Instruct (reuse)\", \"seed\": \"N/A\"}, \"completed_at\": \"2026-05-17T01:02:16.162Z\"}, \"exp-005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T20:52:36.217Z\", \"updated_at\": \"2026-05-16T20:53:22.616Z\", \"hypothesis\": \"QwQ-32B 作为 reasoning model 展示 SICA 的 operating regime boundary: 模型过强→diversity 消失→SICA≡SC\", \"parent\": \"sica_aime30_v3\", \"spec\": {\"command\": \"CPU-only data analysis: aggregate QwQ-32B negative results\", \"server\": \"westd-32608\", \"data_path\": \"results/aime30_v2.json + results/proofwriter_30_v2.json + results/folio_livetest.json + results/diversity_diagnosis.json\", \"data_count\": 46, \"model_name\": \"QwQ-32B (analysis target) vs Qwen2.5-14B-Instruct (comparison)\", \"seed\": \"N/A\", \"checkpoint_source\": \"N/A (CPU-only analysis, no model checkpoint)\", \"eval_data\": \"Aggregated outputs from sica_aime30_v3 (22q), sica_proofwriter30_v2 (17q), sica_folio30 (2q), sica_temp_diversity (5q)\"}, \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"artifacts/exp-005/data/operating_regime_data.json + artifacts/exp-005/report/operating_regime_report.md\", \"metrics\": {\"qwq_aggregate_c0_nominal_pct\": 10.3, \"qwq_aggregate_c0_effective_pct\": 2.6, \"qwen14b_c0_pct\": 46, \"diversity_ratio_effective\": 17.7, \"aime_delta_pp\": 0, \"proofwriter_delta_pp\": -5.9, \"aime_n\": 22, \"proofwriter_n\": 17, \"temp_diversity_n\": 5, \"folio_n\": 2, \"total_problems\": 46, \"c0_threshold\": 20, \"qwq_below_threshold\": true}, \"conclusion\": \"negative\", \"notes\": \"exp-005 Operating Regime Analysis 完成。QwQ-32B 综合 46 题数据：effective C0=2.6%，远低于 20% 阈值。数学域 SICA≡SC (Δ=0pp, AIME 22题)，逻辑域 SICA&lt;SC (Δ=−5.9pp, PW 17题)。对比 Qwen2.5-14B C0=46% (17.7x)。直接支持 paper Claim 2 (operating regime boundary)。Artifacts: art_20260516_bf444f (data), art_20260516_d6966d (report)。\", \"completed_at\": \"2026-05-16T20:53:22.616Z\"}, \"sica_folio30\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:08:43.460Z\", \"updated_at\": \"2026-05-16T04:42:53.530Z\", \"hypothesis\": \"逻辑域（FOLIO）上 SICA 能否利用 FOL 标注检测跨路径矛盾并超越 SC@K=12——FOLIO 有天然 FOL 标注，是 SICA 约束提取的理想场景\", \"parent\": \"sica_aime30_v3\", \"spec\": {\"hypothesis\": \"FOLIO 逻辑域上 SICA 能否利用 FOL 标注检测跨路径矛盾并超越 SC@K=12\", \"dataset\": \"FOLIO (yale-nlp/FOLIO validation subset)\", \"data_path\": \"/root/symb_invariant_consensus/data/folio_subset.json\", \"data_count\": 30, \"label_distribution\": {\"True\": 10, \"False\": 10, \"Unknown\": 10}, \"has_fol_annotations\": true, \"model_name\": \"QwQ-32B\", \"server\": \"westd-32608\", \"command\": \"python eval_folio.py --n-problems 30 --k 12 --temperature 0.7 --max-tokens 12288 --seed 42 --save-intermediates --output results/folio_eval.json\", \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 12288, \"seed\": 42, \"eval_script\": \"/root/symb_invariant_consensus/eval_folio.py\", \"dry_run_passed\": true, \"live_test_passed\": true, \"live_test_result\": \"2/2 correct (SICA=100%, SC=100%), pipeline all stages functional\"}, \"notes\": \"废弃：QwQ-32B spec（max_tokens=12288），已被 sica_d012_14b（Qwen2.5-14B-Instruct 全量 D012 评估）覆盖。QwQ-32B 全域 C0 FAIL (3.6%)，模型已 pivot。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T04:42:50.715Z\"}, \"sica_d016_c0_precheck\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:00:14.192Z\", \"updated_at\": \"2026-05-16T04:01:11.163Z\", \"hypothesis\": \"D016 模型 pivot C0 预检：Qwen2.5-14B-Instruct 在逻辑域是否产生足够 trace 多样性（多候选率 ≥20%）\", \"parent\": \"sica_proofwriter30_v2\", \"spec\": {\"command\": \"python sica_pipeline.py --data folio_subset.json+proofwriter_subset.json --K 6 --T 0.7 --max-tokens 4096 --model Qwen2.5-14B-Instruct\", \"server\": \"westd-32608\", \"data_path\": \"data/folio_subset.json (10q) + data/proofwriter_subset.json (16q)\", \"data_count\": 26, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"gpu\": \"cuda:0\", \"model_path\": \"/root/autodl-tmp/models/Qwen2.5-14B-Instruct\", \"hyperparams\": {\"K\": 6, \"T\": 0.7, \"max_tokens\": 4096, \"max_model_len\": 8192}, \"checkpoint_source\": \"N/A (inference-only, no checkpoint)\", \"eval_data\": \"FOLIO-10 + ProofWriter-16 (C0 precheck subset)\"}, \"metrics\": {\"multi_candidate_rate_combined\": 0.46, \"multi_candidate_rate_folio\": 0.4, \"multi_candidate_rate_proofwriter\": 0.5, \"sc_accuracy_combined\": 0.73, \"sc_accuracy_folio\": 0.8, \"sc_accuracy_proofwriter\": 0.69, \"n_problems\": 26, \"n_folio\": 10, \"n_proofwriter\": 16, \"K\": 6, \"T\": 0.7, \"total_time_s\": 280, \"c0_gate\": \"PASS (46% >= 20%)\", \"model\": \"Qwen2.5-14B-Instruct\", \"vllm_gpu_mem_gib\": 27.6, \"smoke_test\": \"2 problems end-to-end OK, constraints 21-26 per problem\"}, \"conclusion\": \"success\", \"notes\": \"C0 PASS: Qwen2.5-14B-Instruct 多候选率 46% (FOLIO 40%, ProofWriter 50%)，远超 20% 阈值。对比 QwQ-32B 全域 3.6%，提升 12.8x。SC accuracy 73% (FOLIO 80%, PW 69%)。Smoke test 2题 SICA pipeline 端到端通过。vLLM PID 174291, 27.6 GiB, max-model-len=8192。Report: art_20260516_e2774d。\", \"checkpoint_path\": \"N/A (inference-only precheck, no checkpoint)\", \"log_path\": \"artifacts/_project/report/d016_model_pivot_report.md (art_20260516_e2774d)\", \"completed_at\": \"2026-05-16T04:01:11.163Z\"}, \"sica_proofwriter30_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:19:01.325Z\", \"updated_at\": \"2026-05-16T01:38:43.002Z\", \"hypothesis\": \"逻辑域（ProofWriter D5）上 SICA 能否检测跨路径 FOL 约束矛盾并超越 SC@K=12（v2: max_tokens=12288 修复）\", \"parent\": \"sica_proofwriter30\", \"spec\": {\"command\": \"python eval_proofwriter.py --n-problems 30 --k 12 --max-tokens 12288 --seed 42 --save-intermediates --output results/proofwriter_30_v2.json\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"155077\", \"log_path\": \"/root/runs/symb_invariant_consensus/proofwriter30_v2.log\", \"submitted_at\": \"2026-05-15T22:19:16.529Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"method\": \"SICA\", \"model_name\": \"QwQ-32B\", \"data_path\": \"/root/symb_invariant_consensus/data/proofwriter_subset.json\", \"data_count\": 30, \"seed\": 42, \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 12288, \"domain\": \"logic\", \"extraction_prompt\": \"LOGIC_EXTRACTION_PROMPT\", \"z3_timeout_s\": 60, \"checkpoint_source\": \"N/A (new SICA logic domain experiment, retry of sica_proofwriter30 with fixed max_tokens)\", \"eval_data\": \"ProofWriter D5 30 problems (T:10 F:10 U:10)\", \"wall_clock_seconds\": 11503.9, \"gpu_hours\": 3.2}, \"notes\": \"16/30 killed (Director 指令)。D012 四项全 FAIL。MaxSAT 根因诊断结论：三层问题叠加——(1) 约束提取失败 54.4%，QwQ-32B 收到 extraction prompt 后重新推理而非输出 JSON，3/4 多候选题提取为零；(2) 一致投票=一致约束，14/17 题 12/12 同一答案，约束天然不矛盾（正确行为非 bug）；(3) 评分偏差，唯一 SICA≠SC 的题 498_Q8，SICA 给少数派 38 分 > 多数派 27 分，因提取失败非随机。MaxSAT 求解器本身无 bug（注入测试 6/6 通过）。推荐修复：L3 自动注入 answer==trace_answer 约束使不同答案 trace 必有冲突；L1 提取用 system prompt 强制 JSON-only。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T01:31:00.468Z\"}, \"sica_proofwriter30\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:08:42.831Z\", \"updated_at\": \"2026-05-15T22:18:19.326Z\", \"hypothesis\": \"逻辑域（ProofWriter D5）上 SICA 能否检测跨路径 FOL 约束矛盾并超越 SC@K=12——验证 SICA 在逻辑推理域的有效性\", \"parent\": \"sica_aime30_v3\", \"spec\": {\"command\": \"python eval_proofwriter.py --n-problems 30 --k 12 --max-tokens 16384 --seed 42 --save-intermediates --output results/proofwriter_30_eval.json\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"153924\", \"log_path\": \"/root/runs/symb_invariant_consensus/proofwriter30.log\", \"submitted_at\": \"2026-05-15T22:11:44.644Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"method\": \"SICA\", \"model_name\": \"QwQ-32B\", \"data_path\": \"/root/symb_invariant_consensus/data/proofwriter_subset.json\", \"data_count\": 30, \"seed\": 42, \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 16384, \"domain\": \"logic\", \"extraction_prompt\": \"LOGIC_EXTRACTION_PROMPT\", \"z3_timeout_s\": 60, \"checkpoint_source\": \"N/A (not eval - new SICA logic domain experiment)\", \"eval_data\": \"ProofWriter D5 30 problems (T:10 F:10 U:10)\", \"wall_clock_seconds\": 378.0, \"gpu_hours\": 0.1}, \"reproduce\": {\"finished_at\": \"2026-05-15T22:15:57.895Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:15:58.664228+00:00\"}]}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T22:18:02.631Z\", \"notes\": \"配置错误导致完全失败。--max-tokens 16384 等于 vLLM 的 --max-model-len 16384，prompt 输入空间为 0，所有 30 题从第 1 题起全部 400 Bad Request。没有生成任何 trace，没有提取约束，没有投票。4 分钟内跑完（全是 retry 耗时）。无法评估 sanity check 标准。需要用 --max-tokens 12288 或更小值重跑（AIME 实验用的 10240 正常工作）。\", \"metrics\": {\"sica_accuracy\": \"0/30 (0.0%)\", \"sc_accuracy\": \"0/30 (0.0%)\", \"sica_sc_gap_pp\": 0, \"total_wall_time_s\": 238.9, \"total_wall_time_min\": 4, \"avg_time_per_problem_s\": 8, \"traces_generated\": 0, \"constraints_extracted\": 0, \"traces_with_constraints\": 0, \"unique_constraints\": 0, \"maxsat_satisfied\": 0, \"maxsat_excluded\": 0, \"multi_candidate_rate\": \"N/A (no traces generated)\", \"vote_diversity\": \"N/A\", \"z3_errors\": 0, \"z3_timeouts\": 0, \"problems_with_contradiction\": 0, \"problems_with_votes\": 0, \"failure_mode\": \"ALL_400_BAD_REQUEST\", \"failure_count\": \"30/30\", \"root_cause\": \"max_tokens=16384 equals max_model_len=16384, leaving 0 tokens for prompt input. Every API call returns 400.\"}, \"checkpoint_path\": \"/root/symb_invariant_consensus/results/proofwriter_30_eval.json\", \"log_path\": \"/root/runs/symb_invariant_consensus/proofwriter30.log\"}, \"sica_aime30_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:13:04.296Z\", \"updated_at\": \"2026-05-15T22:07:55.967Z\", \"hypothesis\": \"AIME 2024 上 SICA 能否检测跨路径矛盾并超越 SC@K=12（v3: timeout=1800s, 从v2 P5恢复继续）\", \"spec\": {\"command\": \"PYTHONUNBUFFERED=1 python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 10240 --math-data data/aime2024_subset.json --output results/aime30_v2.json --no-proofwriter --seed 42 --resume\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"129992\", \"log_path\": \"/root/runs/symb_invariant_consensus/sica_aime30_v2_resume.log\", \"account\": \"root\", \"method\": \"SICA\", \"model_name\": \"QwQ-32B\", \"data_path\": \"/root/symb_invariant_consensus/data/aime2024_subset.json\", \"data_count\": 30, \"seed\": 42, \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 10240, \"fixes\": \"timeout=1800s; n=4 batching on disk but not loaded by running process\", \"resumed_from\": \"sica_aime30_v2 (4/30 completed)\", \"remaining_problems\": 26}, \"parent\": \"sica_aime30_v2\", \"notes\": \"v3 killed at 22/30 (PID 129992, 6h11m). Vote diversity analysis: multi-candidate rate = 0.0%, all valid problems have exactly 1 candidate. SICA≡SC confirmed structural. 6/22 problems with 0 votes (extraction failure). 数学域结论锁定，转逻辑域。\", \"metrics\": {\"progress\": \"22/30\", \"sica_accuracy_interim\": \"16/22 (72.7%)\", \"sc_accuracy_interim\": \"16/22 (72.7%)\", \"sica_sc_gap_pp\": 0, \"avg_time_per_problem_s\": 645.9, \"runtime_h\": 5.9, \"remaining_problems\": 8, \"vote_diversity_analysis\": {\"valid_problems\": 16, \"total_problems\": 22, \"multi_candidate_rate\": 0, \"zero_vote_problems\": 6, \"zero_vote_indices\": [1, 7, 8, 10, 13, 14], \"constraints_extracted\": \"19/22\", \"exclusion_rate\": 0.387, \"conclusion\": \"All 16 valid problems have exactly 1 candidate answer. SICA≡SC structurally. MaxSAT exclusion operates but cannot change final selection with only 1 candidate.\"}, \"process_status\": \"gone (cron miss 1/5)\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T22:07:52.491Z\"}, \"sica_aime30_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:24:26.526Z\", \"updated_at\": \"2026-05-15T16:11:32.132Z\", \"spec\": {\"command\": \"PYTHONUNBUFFERED=1 python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 10240 --math-data data/aime2024_subset.json --output results/aime30_v2.json --no-proofwriter --seed 42\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"121139\", \"log_path\": \"/tmp/sica_aime30_v2.log\", \"submitted_at\": \"2026-05-15T13:24:26.512Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"method\": \"SICA\", \"model_name\": \"QwQ-32B\", \"data_path\": \"/root/symb_invariant_consensus/data/aime2024_subset.json\", \"data_count\": 30, \"k\": 12, \"temperature\": 0.7, \"max_tokens\": 10240, \"seed\": null, \"seed_note\": \"--seed 42 在命令行中但 run_full_mvp.py 可能未实现该参数，实际 seed 未生效\", \"fixes\": \"timeout=120s HTTP, future timeout=180s, semaphore(6), vLLM health check\", \"wall_clock_seconds\": 8899.6, \"gpu_hours\": 2.47}, \"hypothesis\": \"AIME 2024 上 SICA 能否检测跨路径矛盾并超越 SC@K=12（v2: 修复 timeout/hang bug 后重跑）\", \"conclusion\": \"killed\", \"metrics\": {\"progress\": \"4/30\", \"sica_accuracy_interim\": \"3/4 (75%)\", \"sc_accuracy_interim\": \"3/4 (75%)\", \"avg_time_per_problem_s\": 557, \"p2_z3_error\": \"Z3Exception on z3_maxsat.py:163, 0 constraints extracted\", \"p5_vllm_stuck\": \"vLLM timeout since ~22:11, retried multiple rounds\", \"issue\": \"vLLM service likely crashed or OOM at Problem 5\", \"analysis_contradiction_rate_aime\": \"50% (2/4)\", \"analysis_contradiction_rate_math\": \"20% (1/5)\", \"analysis_unique_constraints_per_problem_aime\": 18.7, \"analysis_exclusion_rate\": \"10.7%\", \"analysis_sica_sc_agreement\": \"9/9 (100%)\", \"analysis_signal\": \"weak positive - mechanism works but SC too unanimous to flip\", \"analysis_p2_failure\": \"0 constraints, 0 votes - answer extraction failure\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T15:52:45.450Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"completed_at\": \"2026-05-15T15:52:46.068Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:52:46.737218+00:00\"}]}, \"notes\": \"失败原因: Problem 5 (aime2024_II_05, 凸六边形几何题) 12条并发trace在单GPU上竞争资源→每条trace吞吐极低→客户端~600s超时后重试→旧请求仍在vLLM running→恶性循环卡死~1h47min | 已有成果: 4/30题完成 SICA 3/4=75% SC 3/4=75%, P2有Z3Exception(0 constraints extracted) | vLLM本身健康(test request <1s) | 建议: 降低并发k或分批处理trace(如4条/批), 增大client timeout, kill stuck requests后重启\"}, \"sica_aime30_t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:38:16.330Z\", \"updated_at\": \"2026-05-15T13:11:37.911Z\", \"spec\": {\"command\": \"python run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 10240 --math-data data/aime2024_subset.json --output results/aime30_t07.json --no-proofwriter\", \"server\": \"westd-32608\", \"gpu\": [\"cuda:0\"], \"pid\": \"119338\", \"log_path\": \"~/runs/symb_invariant_consensus/sica_aime30_t07.log\", \"submitted_at\": \"2026-05-15T13:01:07.184Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/aime2024_subset.json\", \"data_count\": 30, \"model_name\": \"QwQ-32B\", \"seed\": null, \"wall_clock_seconds\": 630.7, \"gpu_hours\": 0.18}, \"hypothesis\": \"AIME 2024（QwQ-32B 弱项，~79.5% acc）上 SICA 能否检测更多跨路径矛盾并超越 SC@K=12——验证\\\"SICA 价值随问题难度递增\\\"假设\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T13:11:37.911Z\"}, \"mvp_math50_t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:16:29.416Z\", \"updated_at\": \"2026-05-15T12:21:37.283Z\", \"spec\": {\"command\": \"nohup python3 run_full_mvp.py --mode vllm --k 12 --output results/mvp_math50_t07.json > /tmp/mvp_math50.log 2>&1 &\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/data/math500_subset.json\", \"data_count\": 50, \"model_name\": \"QwQ-32B\", \"seed\": 42, \"method\": \"SICA\", \"checkpoint_path\": \"results/mvp_math50_t07.json\", \"log_path\": \"/tmp/mvp_math50.log\", \"temperature\": 0.7, \"k\": 12}, \"hypothesis\": \"SICA MVP: 50题MATH-500上跨路径MAX-SAT约束共识能否检测矛盾并超越SC@K=12\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T12:21:37.283Z\"}, \"sica_smoke_5q\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:38:43.996Z\", \"updated_at\": \"2026-05-15T11:39:13.456Z\", \"spec\": {\"command\": \"python3 smoke_test_5q.py (nohup)\", \"server\": \"westd-32608\", \"data_path\": \"/root/symb_invariant_consensus/data/math500_subset.json\", \"data_count\": 5, \"model_name\": \"QwQ-32B\", \"seed\": 42, \"method\": \"SICA\", \"checkpoint_path\": \"N/A\", \"log_path\": \"/tmp/smoke_test_5q.log\"}, \"hypothesis\": \"SICA smoke test: 验证端到端 pipeline 可行性（5题 MATH-500, K=12, QwQ-32B）\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T11:39:07.006Z\", \"metrics\": {\"sica_accuracy\": 0.8, \"sc_accuracy\": 0.8, \"extraction_rate\": 1, \"problems_with_contradictions\": 1, \"total_problems\": 5, \"total_time_s\": 3505, \"avg_time_per_problem_s\": 701, \"per_problem\": [{\"id\": \"algebra/2470\", \"level\": 1, \"sica_correct\": true, \"sc_correct\": true, \"constraints\": 27, \"unique\": 9, \"excluded\": 0}, {\"id\": \"prealgebra/65\", \"level\": 2, \"sica_correct\": true, \"sc_correct\": true, \"constraints\": 26, \"unique\": 2, \"excluded\": 0}, {\"id\": \"number_theory/847\", \"level\": 3, \"sica_correct\": true, \"sc_correct\": true, \"constraints\": 21, \"unique\": 11, \"excluded\": 0, \"note\": \"14 JSON parse failures, 1693s\"}, {\"id\": \"precalculus/1199\", \"level\": 4, \"sica_correct\": false, \"sc_correct\": false, \"constraints\": 35, \"unique\": 6, \"excluded\": 0, \"note\": \"graph-reading problem, model cannot see image\"}, {\"id\": \"algebra/2277\", \"level\": 5, \"sica_correct\": true, \"sc_correct\": true, \"constraints\": 60, \"unique\": 6, \"satisfied\": 3, \"excluded\": 3}]}}, \"smoke-test-5q\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:22:09.665Z\", \"updated_at\": \"2026-05-15T11:22:09.666Z\", \"conclusion\": \"failed\"}, \"crd_folio_main\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:35:42.037Z\", \"updated_at\": \"2026-05-15T09:36:24.832Z\", \"spec\": {\"command\": \"python run_pipeline.py (CRD dual-representation pipeline)\", \"server\": \"westd-32608\", \"data_path\": \"/root/autodl-tmp/crdd/results/mvp_v4_full.jsonl\", \"data_count\": 204, \"model_name\": \"Qwen3-32B-AWQ\", \"seed\": 42, \"method\": \"CRD\", \"checkpoint_path\": \"N/A\", \"log_path\": \"/root/autodl-tmp/crdd/results/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T09:36:03.793Z\", \"hypothesis\": \"CRD: 双表征(FOL+SymPy)分歧检测+定向修复能提升逻辑推理准确率（非SICA方法）\", \"metrics\": {\"divergence_rate\": 0.422, \"diagnosis_rate\": 0.872, \"error_types\": 4, \"directed_advantage_pp\": 4.7, \"directed_p_value\": 0.63, \"localization_accuracy\": 0.946, \"fol_accuracy\": 0.789, \"code_accuracy\": 0.598, \"oracle_accuracy\": 0.878, \"pipeline_accuracy\": 0.814, \"baseline_accuracy\": 0.74, \"cost_multiplier\": 5.76, \"dataset\": \"FOLIO\", \"n\": 204}}}, \"count\": 100, \"total\": 100, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.2857}}"
    }
  },
  "sourceToolAssistantUUID": "4e35c5d5-69d9-483d-8993-5931f9bb2852",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-19T14:32:25.971Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_019vgkoFtEHbG8kLqz3hDfi9`</summary>

```json
{
  "project": "symb_invariant_consensus",
  "file": "report.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "765365e4-f4cc-4b57-b8e1-681343d67b94",
  "isSidechain": false,
  "requestId": "req_011CbC6CrsnyrKucF8fHUQq1",
  "type": "assistant",
  "uuid": "a0fc1076-c386-4518-ace6-35dbd58e15bf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01APmHu3mWPmedC4d4pFzQTk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 3529,
      "cache_read_input_tokens": 36913,
      "output_tokens": 259,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3529,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 259,
          "cache_read_input_tokens": 36913,
          "cache_creation_input_tokens": 3529,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3529
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

_source line 16 · 2026-05-19T14:32:26.098Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_roadmap · `toolu_017axJFNcSbc7NDRbez7ZJEe`</summary>

```json
{
  "project": "symb_invariant_consensus"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a0fc1076-c386-4518-ace6-35dbd58e15bf",
  "isSidechain": false,
  "requestId": "req_011CbC6CrsnyrKucF8fHUQq1",
  "type": "assistant",
  "uuid": "c4e603fb-2703-4647-a0f1-96b5b534862a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01APmHu3mWPmedC4d4pFzQTk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 3529,
      "cache_read_input_tokens": 36913,
      "output_tokens": 259,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3529,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 259,
          "cache_read_input_tokens": 36913,
          "cache_creation_input_tokens": 3529,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3529
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
  "lastPrompt": "[CRON] 实验进程异常退出（失败），需要你诊断原因。 详情: Process exited without valid W&B metrics  - exp_id: exp-069-llama8b-logiqa200 - project: symb_invariant_consensus - server: westd-16639",
  "leafUuid": "c4e603fb-2703-4647-a0f1-96b5b534862a",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327"
}
```

---

### Runtime record

_source line 18_

```json
{
  "type": "ai-title",
  "aiTitle": "Diagnose W&B metrics missing from experiment exit",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327"
}
```

---

### Tool result

_source line 19 · 2026-05-19T14:32:35.392Z_

<details><summary>↩ Tool result · `toolu_011MvopQRPRbn9JDKcJL63oc`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"reconciled\": 4, \"results\": [{\"exp_id\": \"exp-048-llama8b-pw600\", \"success\": true, \"actions\": [\"Job still running (pid=exp048_run)\"]}, {\"exp_id\": \"exp-062-gemma27b-folio204\", \"success\": true, \"actions\": [\"Job still running (pid=exp062_run)\"]}, {\"exp_id\": \"exp-065-qwen7b-pw600\", \"success\": true, \"actions\": [\"Job still running (pid=exp065_run)\"]}, {\"exp_id\": \"exp-064-deepseek-r1-qwen3-8b-folio204\", \"success\": true, \"actions\": [\"Job still running (pid=153381)\"]}]}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b040030f-c815-4a0e-8f2a-566a5a9d5c29",
  "isSidechain": false,
  "promptId": "62ab6029-0ec6-4d33-8f75-d725e1fbd51a",
  "type": "user",
  "uuid": "d39451cb-44a5-45cf-af1e-b8dd89298bf6",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"reconciled\\\": 4, \\\"results\\\": [{\\\"exp_id\\\": \\\"exp-048-llama8b-pw600\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=exp048_run)\\\"]}, {\\\"exp_id\\\": \\\"exp-062-gemma27b-folio204\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=exp062_run)\\\"]}, {\\\"exp_id\\\": \\\"exp-065-qwen7b-pw600\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=exp065_run)\\\"]}, {\\\"exp_id\\\": \\\"exp-064-deepseek-r1-qwen3-8b-folio204\\\", \\\"success\\\": true, \\\"actions\\\": [\\\"Job still running (pid=153381)\\\"]}]}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"reconciled\": 4, \"results\": [{\"exp_id\": \"exp-048-llama8b-pw600\", \"success\": true, \"actions\": [\"Job still running (pid=exp048_run)\"]}, {\"exp_id\": \"exp-062-gemma27b-folio204\", \"success\": true, \"actions\": [\"Job still running (pid=exp062_run)\"]}, {\"exp_id\": \"exp-065-qwen7b-pw600\", \"success\": true, \"actions\": [\"Job still running (pid=exp065_run)\"]}, {\"exp_id\": \"exp-064-deepseek-r1-qwen3-8b-folio204\", \"success\": true, \"actions\": [\"Job still running (pid=153381)\"]}]}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "b040030f-c815-4a0e-8f2a-566a5a9d5c29",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-19T14:32:35.406Z_

<details><summary>↩ Tool result · `toolu_019vgkoFtEHbG8kLqz3hDfi9`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/report.md\", \"content\": \"&lt;!-- AUTO-FACTS-BEGIN (generated 2026-05-19T14:32:09Z; do not edit — regenerated by auto_build_report_facts) -->\\n## 📊 当前状态（auto-derived from registry）\\n\\n**总计**: 100 个实验 — DONE 92, PREPARING 2, QUEUED 2, RUNNING 4\\n**DONE 分布**: failed 18, killed 10, negative 40, success 24\\n\\n### GPU 占用\\n- **实际运行**: 4 张 — westd-16639:cuda:3(exp-048-llama8b-pw600), westd-25068:cuda:3(exp-062-gemma27b-folio204), westd-16639:cuda:0(exp-064-deepseek-r1-qwen3-8b-folio204), westd-25068:cuda:0(exp-065-qwen7b-pw600)\\n\\n### 💾 磁盘余量\\n- **westd-25068**:\\n  - `/init`: 150M/150M 可用（已用 0%）\\n  - `/autodl-pub`: 5.3T/7.3T 可用（已用 24%）\\n  - `/usr/bin/nvidia-smi`: 431G/879G 可用（已用 49%）\\n- **westd-16639**:\\n  - `/autodl-pub`: 5.3T/7.3T 可用（已用 24%）\\n  - `/init`: 150M/150M 可用（已用 1%）\\n  - `/usr/bin/nvidia-smi`: 502G/879G 可用（已用 40%）\\n\\n### 🏃 RUNNING\\n| exp_id | server | gpu | pid | log |\\n|--------|--------|-----|-----|-----|\\n| `exp-048-llama8b-pw600` | westd-16639 | cuda:3 | ? | `—` |\\n| `exp-062-gemma27b-folio204` | westd-25068 | cuda:3 | ? | `—` |\\n| `exp-064-deepseek-r1-qwen3-8b-folio204` | westd-16639 | cuda:0 | ? | `—` |\\n| `exp-065-qwen7b-pw600` | westd-25068 | cuda:0 | ? | `—` |\\n\\n### 📌 最近完成 (top 5)\\n- `exp-069-llama8b-logiqa200` [failed] — 2026-05-19T14:32:06 — process dead 5× with no sentinel/W&B — auto-resolved as failed\\n- `exp-069-mistral-logiqa200` [negative] — 2026-05-19T14:19:37\\n- `exp-070-qwen7b-logiqa200` [success] — 2026-05-19T14:18:52\\n- `exp-068-qwen3-logiqa200` [negative] — 2026-05-19T13:53:10\\n- `exp-064` [killed] — 2026-05-19T12:13:57\\n\\n### 🔴 最近失败原因 (top 3)\\n- `exp-069-llama8b-logiqa200`: process dead 5× with no sentinel/W&B — auto-resolved as failed\\n- `exp-064`: _(no failure_reason — pre-2026-04-24 entry)_\\n\\n&lt;!-- AUTO-FACTS-END -->\\n\\n---\\n\\n# Handover — 2026-05-19\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| exp-064-deepseek-r1-qwen3-8b-folio204 | DeepSeek-R1-0528-Qwen3-8B (reasoning distill) 在 FOLIO-204 上 SICA vs SC。测试 reasoning 模型在 8B scale 是否出现 degenerate regime (C₀<5%) 或因 8B 能力较弱落入 error amplification / Goldilocks zone。 | — | — | — |\\n| exp-062-gemma27b-folio204 | Gemma-3-27B-IT (Google 架构) FOLIO-204 SICA vs SC。跨模型家族验证 regime-dependent pattern。27B 能力预计在 Qwen2.5-14B (~75% SC) 和 Qwen3-14B (~85% SC) 之间。 | — | — | — |\\n| exp-065-qwen7b-pw600 | Qwen2.5-7B 在 PW-D5-600 上 SICA vs SC。FOLIO SC=75.98% (confirmation bias)，PW 更难 SC 预计更低，测试不同 regime。parent=exp-061 | — | — | — |\\n\\n## 待处理\\n- exp-053-mistral-folio204-seed456: exp-033 replication (seed=456): Mistral-7B FOLIO-204 K=12 T=0.7，第二组独立 replication。与 exp-052 (seed=123) 一起验证 exp-033 结论 robustness。parent=exp-033（排队等待 GPU）\\n- exp-052-mistral-folio204-seed123: exp-033 replication (seed=123): Mistral-7B FOLIO-204 K=12 T=0.7，与 exp-033 (seed=42, delta=+4.90pp, p=0.013) 完全相同配置，仅 seed 不同。验证正向结果是否 seed-robust。parent=exp-033（排队等待 GPU）\\n- exp-063-llama8b-folio204（准备中）\\n- smoke-test-5q（准备中）\\n\\n## 近期结论\\n- **exp-069-llama8b-logiqa200** (failed): LLaMA-3.1-8B-Instruct 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 LLaMA-8B SC=66.18% delta=-4.41pp (exp-063, negative/error amplification)。LogiQA 上 Mistral-7B SC=51% delta=+0.5pp (exp-049b)，Qwen2.5-14B SC=78.5% delta=-0.50pp (exp-038)。测试 LLaMA-8B 在 LogiQA 上的 regime（SC 预计 50-60%，可能在 error amplification zone）。parent=exp-063-llama8b-folio204-16639 ← 基于 exp-063-llama8b-folio204-16639\\n- **exp-069-mistral-logiqa200** (negative): Mistral-7B-Instruct-v0.3 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 Mistral 是唯一 Goldilocks 候选 (SC≈55%, Δ=+4.90pp seed=42)。如果 LogiQA SC 也在 55-65% 且 Δ>0，则跨数据集验证 Goldilocks zone 存在。parent=exp-033 ← 基于 exp-033\\n- **exp-070-qwen7b-logiqa200** (success): Qwen2.5-7B-Instruct 在 LogiQA-200 上 SICA vs SC。FOLIO 上 SC=75.98% (Type A confirmation bias, Δ=+0.49pp)。LogiQA 可能更难，SC 可能降到 55-65% 进入 Goldilocks zone，或保持 >75% 继续 Type A。验证 regime 跨数据集一致性。parent=exp-061 ← 基于 exp-061\\n\\n## 趋势\\n成功 24 / 负向 40 / 失败 18 / 共 92\\nsc_accuracy: 0.685 ↑（近 3 次 success）\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nwestd-16639: 空闲 cuda:0, cuda:1, cuda:2, cuda:3\\nwestd-25068: 无 GPU 信息\\n\\n## 告警\\n- mvp_math50_t07: 已被终止 — unknown\\n- sica_aime30_t07: 已被终止 — unknown\\n- sica_aime30_v2: 已被终止 — unknown\\n- sica_aime30_v3: 已被终止 — unknown\\n- sica_proofwriter30: 训练失败 — unknown\\n- sica_folio30: 已被终止 — unknown\\n- sica_proofwriter30_v2: 已被终止 — unknown\\n- exp-011-llama8b: 训练失败 — unknown\\n- exp-010-mistral: 训练失败 — unknown\\n- exp-011-llama8b-v2: 训练失败 — unknown\\n- exp-017-strategyqa: 训练失败 — unknown\\n- exp-018-arc: 训练失败 — unknown\\n- exp-010-mistral-v2: 训练失败 — unknown\\n- exp-017-strategyqa-v2: 训练失败 — unknown\\n- pilot-contrastive-prompt: 训练失败 — unknown\\n- exp-028-qwen3-14b-thinking: 已被终止 — unknown\\n- exp-033-qwen3-pw600-nonthinking: 训练失败 — unknown\\n- exp-007-qwen72b-awq: 训练失败 — unknown\\n- exp-004-qwen7b-rerun: 训练失败 — unknown\\n- exp-042-premise-formalization: 训练失败 — unknown\\n- exp-044-icl-oracle: 训练失败 — unknown\\n- exp-042b-premise-formal: 训练失败 — unknown\\n- exp-045b-backward-verify: 已被终止 — unknown\\n- exp-028b-qwen3-thinking-folio204: 已被终止 — unknown\\n- exp-049-mistral-logiqa200: 训练失败 — unknown\\n- exp-050-mistral-icl-oracle-folio199: 训练失败 — unknown\\n- exp-064: 已被终止 — unknown\\n- exp-069-llama8b-logiqa200: 训练失败 — unknown\\n\", \"total_chars\": 5103, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a0fc1076-c386-4518-ace6-35dbd58e15bf",
  "isSidechain": false,
  "promptId": "62ab6029-0ec6-4d33-8f75-d725e1fbd51a",
  "type": "user",
  "uuid": "8ef5224c-9069-4b9d-aa4d-310188e3555d",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/report.md\\\", \\\"content\\\": \\\"&lt;!-- AUTO-FACTS-BEGIN (generated 2026-05-19T14:32:09Z; do not edit — regenerated by auto_build_report_facts) -->\\\\n## 📊 当前状态（auto-derived from registry）\\\\n\\\\n**总计**: 100 个实验 — DONE 92, PREPARING 2, QUEUED 2, RUNNING 4\\\\n**DONE 分布**: failed 18, killed 10, negative 40, success 24\\\\n\\\\n### GPU 占用\\\\n- **实际运行**: 4 张 — westd-16639:cuda:3(exp-048-llama8b-pw600), westd-25068:cuda:3(exp-062-gemma27b-folio204), westd-16639:cuda:0(exp-064-deepseek-r1-qwen3-8b-folio204), westd-25068:cuda:0(exp-065-qwen7b-pw600)\\\\n\\\\n### 💾 磁盘余量\\\\n- **westd-25068**:\\\\n  - `/init`: 150M/150M 可用（已用 0%）\\\\n  - `/autodl-pub`: 5.3T/7.3T 可用（已用 24%）\\\\n  - `/usr/bin/nvidia-smi`: 431G/879G 可用（已用 49%）\\\\n- **westd-16639**:\\\\n  - `/autodl-pub`: 5.3T/7.3T 可用（已用 24%）\\\\n  - `/init`: 150M/150M 可用（已用 1%）\\\\n  - `/usr/bin/nvidia-smi`: 502G/879G 可用（已用 40%）\\\\n\\\\n### 🏃 RUNNING\\\\n| exp_id | server | gpu | pid | log |\\\\n|--------|--------|-----|-----|-----|\\\\n| `exp-048-llama8b-pw600` | westd-16639 | cuda:3 | ? | `—` |\\\\n| `exp-062-gemma27b-folio204` | westd-25068 | cuda:3 | ? | `—` |\\\\n| `exp-064-deepseek-r1-qwen3-8b-folio204` | westd-16639 | cuda:0 | ? | `—` |\\\\n| `exp-065-qwen7b-pw600` | westd-25068 | cuda:0 | ? | `—` |\\\\n\\\\n### 📌 最近完成 (top 5)\\\\n- `exp-069-llama8b-logiqa200` [failed] — 2026-05-19T14:32:06 — process dead 5× with no sentinel/W&B — auto-resolved as failed\\\\n- `exp-069-mistral-logiqa200` [negative] — 2026-05-19T14:19:37\\\\n- `exp-070-qwen7b-logiqa200` [success] — 2026-05-19T14:18:52\\\\n- `exp-068-qwen3-logiqa200` [negative] — 2026-05-19T13:53:10\\\\n- `exp-064` [killed] — 2026-05-19T12:13:57\\\\n\\\\n### 🔴 最近失败原因 (top 3)\\\\n- `exp-069-llama8b-logiqa200`: process dead 5× with no sentinel/W&B — auto-resolved as failed\\\\n- `exp-064`: _(no failure_reason — pre-2026-04-24 entry)_\\\\n\\\\n&lt;!-- AUTO-FACTS-END -->\\\\n\\\\n---\\\\n\\\\n# Handover — 2026-05-19\\\\n\\\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\\\n\\\\n## 运行中\\\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\\\n|--------|------|------|---------|-----|\\\\n| exp-064-deepseek-r1-qwen3-8b-folio204 | DeepSeek-R1-0528-Qwen3-8B (reasoning distill) 在 FOLIO-204 上 SICA vs SC。测试 reasoning 模型在 8B scale 是否出现 degenerate regime (C₀<5%) 或因 8B 能力较弱落入 error amplification / Goldilocks zone。 | — | — | — |\\\\n| exp-062-gemma27b-folio204 | Gemma-3-27B-IT (Google 架构) FOLIO-204 SICA vs SC。跨模型家族验证 regime-dependent pattern。27B 能力预计在 Qwen2.5-14B (~75% SC) 和 Qwen3-14B (~85% SC) 之间。 | — | — | — |\\\\n| exp-065-qwen7b-pw600 | Qwen2.5-7B 在 PW-D5-600 上 SICA vs SC。FOLIO SC=75.98% (confirmation bias)，PW 更难 SC 预计更低，测试不同 regime。parent=exp-061 | — | — | — |\\\\n\\\\n## 待处理\\\\n- exp-053-mistral-folio204-seed456: exp-033 replication (seed=456): Mistral-7B FOLIO-204 K=12 T=0.7，第二组独立 replication。与 exp-052 (seed=123) 一起验证 exp-033 结论 robustness。parent=exp-033（排队等待 GPU）\\\\n- exp-052-mistral-folio204-seed123: exp-033 replication (seed=123): Mistral-7B FOLIO-204 K=12 T=0.7，与 exp-033 (seed=42, delta=+4.90pp, p=0.013) 完全相同配置，仅 seed 不同。验证正向结果是否 seed-robust。parent=exp-033（排队等待 GPU）\\\\n- exp-063-llama8b-folio204（准备中）\\\\n- smoke-test-5q（准备中）\\\\n\\\\n## 近期结论\\\\n- **exp-069-llama8b-logiqa200** (failed): LLaMA-3.1-8B-Instruct 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 LLaMA-8B SC=66.18% delta=-4.41pp (exp-063, negative/error amplification)。LogiQA 上 Mistral-7B SC=51% delta=+0.5pp (exp-049b)，Qwen2.5-14B SC=78.5% delta=-0.50pp (exp-038)。测试 LLaMA-8B 在 LogiQA 上的 regime（SC 预计 50-60%，可能在 error amplification zone）。parent=exp-063-llama8b-folio204-16639 ← 基于 exp-063-llama8b-folio204-16639\\\\n- **exp-069-mistral-logiqa200** (negative): Mistral-7B-Instruct-v0.3 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 Mistral 是唯一 Goldilocks 候选 (SC≈55%, Δ=+4.90pp seed=42)。如果 LogiQA SC 也在 55-65% 且 Δ>0，则跨数据集验证 Goldilocks zone 存在。parent=exp-033 ← 基于 exp-033\\\\n- **exp-070-qwen7b-logiqa200** (success): Qwen2.5-7B-Instruct 在 LogiQA-200 上 SICA vs SC。FOLIO 上 SC=75.98% (Type A confirmation bias, Δ=+0.49pp)。LogiQA 可能更难，SC 可能降到 55-65% 进入 Goldilocks zone，或保持 >75% 继续 Type A。验证 regime 跨数据集一致性。parent=exp-061 ← 基于 exp-061\\\\n\\\\n## 趋势\\\\n成功 24 / 负向 40 / 失败 18 / 共 92\\\\nsc_accuracy: 0.685 ↑（近 3 次 success）\\\\n\\\\n## 下一步\\\\n（无活跃 idea，请通过 ideas.md 添加）\\\\n\\\\n## 资源状态\\\\nwestd-16639: 空闲 cuda:0, cuda:1, cuda:2, cuda:3\\\\nwestd-25068: 无 GPU 信息\\\\n\\\\n## 告警\\\\n- mvp_math50_t07: 已被终止 — unknown\\\\n- sica_aime30_t07: 已被终止 — unknown\\\\n- sica_aime30_v2: 已被终止 — unknown\\\\n- sica_aime30_v3: 已被终止 — unknown\\\\n- sica_proofwriter30: 训练失败 — unknown\\\\n- sica_folio30: 已被终止 — unknown\\\\n- sica_proofwriter30_v2: 已被终止 — unknown\\\\n- exp-011-llama8b: 训练失败 — unknown\\\\n- exp-010-mistral: 训练失败 — unknown\\\\n- exp-011-llama8b-v2: 训练失败 — unknown\\\\n- exp-017-strategyqa: 训练失败 — unknown\\\\n- exp-018-arc: 训练失败 — unknown\\\\n- exp-010-mistral-v2: 训练失败 — unknown\\\\n- exp-017-strategyqa-v2: 训练失败 — unknown\\\\n- pilot-contrastive-prompt: 训练失败 — unknown\\\\n- exp-028-qwen3-14b-thinking: 已被终止 — unknown\\\\n- exp-033-qwen3-pw600-nonthinking: 训练失败 — unknown\\\\n- exp-007-qwen72b-awq: 训练失败 — unknown\\\\n- exp-004-qwen7b-rerun: 训练失败 — unknown\\\\n- exp-042-premise-formalization: 训练失败 — unknown\\\\n- exp-044-icl-oracle: 训练失败 — unknown\\\\n- exp-042b-premise-formal: 训练失败 — unknown\\\\n- exp-045b-backward-verify: 已被终止 — unknown\\\\n- exp-028b-qwen3-thinking-folio204: 已被终止 — unknown\\\\n- exp-049-mistral-logiqa200: 训练失败 — unknown\\\\n- exp-050-mistral-icl-oracle-folio199: 训练失败 — unknown\\\\n- exp-064: 已被终止 — unknown\\\\n- exp-069-llama8b-logiqa200: 训练失败 — unknown\\\\n\\\", \\\"total_chars\\\": 5103, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/report.md\", \"content\": \"&lt;!-- AUTO-FACTS-BEGIN (generated 2026-05-19T14:32:09Z; do not edit — regenerated by auto_build_report_facts) -->\\n## 📊 当前状态（auto-derived from registry）\\n\\n**总计**: 100 个实验 — DONE 92, PREPARING 2, QUEUED 2, RUNNING 4\\n**DONE 分布**: failed 18, killed 10, negative 40, success 24\\n\\n### GPU 占用\\n- **实际运行**: 4 张 — westd-16639:cuda:3(exp-048-llama8b-pw600), westd-25068:cuda:3(exp-062-gemma27b-folio204), westd-16639:cuda:0(exp-064-deepseek-r1-qwen3-8b-folio204), westd-25068:cuda:0(exp-065-qwen7b-pw600)\\n\\n### 💾 磁盘余量\\n- **westd-25068**:\\n  - `/init`: 150M/150M 可用（已用 0%）\\n  - `/autodl-pub`: 5.3T/7.3T 可用（已用 24%）\\n  - `/usr/bin/nvidia-smi`: 431G/879G 可用（已用 49%）\\n- **westd-16639**:\\n  - `/autodl-pub`: 5.3T/7.3T 可用（已用 24%）\\n  - `/init`: 150M/150M 可用（已用 1%）\\n  - `/usr/bin/nvidia-smi`: 502G/879G 可用（已用 40%）\\n\\n### 🏃 RUNNING\\n| exp_id | server | gpu | pid | log |\\n|--------|--------|-----|-----|-----|\\n| `exp-048-llama8b-pw600` | westd-16639 | cuda:3 | ? | `—` |\\n| `exp-062-gemma27b-folio204` | westd-25068 | cuda:3 | ? | `—` |\\n| `exp-064-deepseek-r1-qwen3-8b-folio204` | westd-16639 | cuda:0 | ? | `—` |\\n| `exp-065-qwen7b-pw600` | westd-25068 | cuda:0 | ? | `—` |\\n\\n### 📌 最近完成 (top 5)\\n- `exp-069-llama8b-logiqa200` [failed] — 2026-05-19T14:32:06 — process dead 5× with no sentinel/W&B — auto-resolved as failed\\n- `exp-069-mistral-logiqa200` [negative] — 2026-05-19T14:19:37\\n- `exp-070-qwen7b-logiqa200` [success] — 2026-05-19T14:18:52\\n- `exp-068-qwen3-logiqa200` [negative] — 2026-05-19T13:53:10\\n- `exp-064` [killed] — 2026-05-19T12:13:57\\n\\n### 🔴 最近失败原因 (top 3)\\n- `exp-069-llama8b-logiqa200`: process dead 5× with no sentinel/W&B — auto-resolved as failed\\n- `exp-064`: _(no failure_reason — pre-2026-04-24 entry)_\\n\\n&lt;!-- AUTO-FACTS-END -->\\n\\n---\\n\\n# Handover — 2026-05-19\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| exp-064-deepseek-r1-qwen3-8b-folio204 | DeepSeek-R1-0528-Qwen3-8B (reasoning distill) 在 FOLIO-204 上 SICA vs SC。测试 reasoning 模型在 8B scale 是否出现 degenerate regime (C₀<5%) 或因 8B 能力较弱落入 error amplification / Goldilocks zone。 | — | — | — |\\n| exp-062-gemma27b-folio204 | Gemma-3-27B-IT (Google 架构) FOLIO-204 SICA vs SC。跨模型家族验证 regime-dependent pattern。27B 能力预计在 Qwen2.5-14B (~75% SC) 和 Qwen3-14B (~85% SC) 之间。 | — | — | — |\\n| exp-065-qwen7b-pw600 | Qwen2.5-7B 在 PW-D5-600 上 SICA vs SC。FOLIO SC=75.98% (confirmation bias)，PW 更难 SC 预计更低，测试不同 regime。parent=exp-061 | — | — | — |\\n\\n## 待处理\\n- exp-053-mistral-folio204-seed456: exp-033 replication (seed=456): Mistral-7B FOLIO-204 K=12 T=0.7，第二组独立 replication。与 exp-052 (seed=123) 一起验证 exp-033 结论 robustness。parent=exp-033（排队等待 GPU）\\n- exp-052-mistral-folio204-seed123: exp-033 replication (seed=123): Mistral-7B FOLIO-204 K=12 T=0.7，与 exp-033 (seed=42, delta=+4.90pp, p=0.013) 完全相同配置，仅 seed 不同。验证正向结果是否 seed-robust。parent=exp-033（排队等待 GPU）\\n- exp-063-llama8b-folio204（准备中）\\n- smoke-test-5q（准备中）\\n\\n## 近期结论\\n- **exp-069-llama8b-logiqa200** (failed): LLaMA-3.1-8B-Instruct 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 LLaMA-8B SC=66.18% delta=-4.41pp (exp-063, negative/error amplification)。LogiQA 上 Mistral-7B SC=51% delta=+0.5pp (exp-049b)，Qwen2.5-14B SC=78.5% delta=-0.50pp (exp-038)。测试 LLaMA-8B 在 LogiQA 上的 regime（SC 预计 50-60%，可能在 error amplification zone）。parent=exp-063-llama8b-folio204-16639 ← 基于 exp-063-llama8b-folio204-16639\\n- **exp-069-mistral-logiqa200** (negative): Mistral-7B-Instruct-v0.3 在 LogiQA-200 上 SICA vs SC。FOLIO-204 上 Mistral 是唯一 Goldilocks 候选 (SC≈55%, Δ=+4.90pp seed=42)。如果 LogiQA SC 也在 55-65% 且 Δ>0，则跨数据集验证 Goldilocks zone 存在。parent=exp-033 ← 基于 exp-033\\n- **exp-070-qwen7b-logiqa200** (success): Qwen2.5-7B-Instruct 在 LogiQA-200 上 SICA vs SC。FOLIO 上 SC=75.98% (Type A confirmation bias, Δ=+0.49pp)。LogiQA 可能更难，SC 可能降到 55-65% 进入 Goldilocks zone，或保持 >75% 继续 Type A。验证 regime 跨数据集一致性。parent=exp-061 ← 基于 exp-061\\n\\n## 趋势\\n成功 24 / 负向 40 / 失败 18 / 共 92\\nsc_accuracy: 0.685 ↑（近 3 次 success）\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nwestd-16639: 空闲 cuda:0, cuda:1, cuda:2, cuda:3\\nwestd-25068: 无 GPU 信息\\n\\n## 告警\\n- mvp_math50_t07: 已被终止 — unknown\\n- sica_aime30_t07: 已被终止 — unknown\\n- sica_aime30_v2: 已被终止 — unknown\\n- sica_aime30_v3: 已被终止 — unknown\\n- sica_proofwriter30: 训练失败 — unknown\\n- sica_folio30: 已被终止 — unknown\\n- sica_proofwriter30_v2: 已被终止 — unknown\\n- exp-011-llama8b: 训练失败 — unknown\\n- exp-010-mistral: 训练失败 — unknown\\n- exp-011-llama8b-v2: 训练失败 — unknown\\n- exp-017-strategyqa: 训练失败 — unknown\\n- exp-018-arc: 训练失败 — unknown\\n- exp-010-mistral-v2: 训练失败 — unknown\\n- exp-017-strategyqa-v2: 训练失败 — unknown\\n- pilot-contrastive-prompt: 训练失败 — unknown\\n- exp-028-qwen3-14b-thinking: 已被终止 — unknown\\n- exp-033-qwen3-pw600-nonthinking: 训练失败 — unknown\\n- exp-007-qwen72b-awq: 训练失败 — unknown\\n- exp-004-qwen7b-rerun: 训练失败 — unknown\\n- exp-042-premise-formalization: 训练失败 — unknown\\n- exp-044-icl-oracle: 训练失败 — unknown\\n- exp-042b-premise-formal: 训练失败 — unknown\\n- exp-045b-backward-verify: 已被终止 — unknown\\n- exp-028b-qwen3-thinking-folio204: 已被终止 — unknown\\n- exp-049-mistral-logiqa200: 训练失败 — unknown\\n- exp-050-mistral-icl-oracle-folio199: 训练失败 — unknown\\n- exp-064: 已被终止 — unknown\\n- exp-069-llama8b-logiqa200: 训练失败 — unknown\\n\", \"total_chars\": 5103, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "a0fc1076-c386-4518-ace6-35dbd58e15bf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-19T14:32:35.422Z_

<details><summary>↩ Tool result · `toolu_017axJFNcSbc7NDRbez7ZJEe`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/ROADMAP.md\", \"content\": \"# symb_invariant_consensus — Research Dashboard\\n\\n> 最后更新: 2026-05-19 08:41 UTC | 更新原因: D067 confirmed, exp-059/060 done, Paper Agent patches complete, ROADMAP refresh\\n\\n> D067: Quality Ladder L1 NULL confirmed. Cross-model extraction ≈ self-extraction. Bottleneck in traces, not extractor.\\n\\n## 核心方向\\n**Independence Bottleneck Analysis.** Oracle +14.22pp (p<0.001) 证明框架有效，但 self-extraction 仅捕获 24% ceiling。Cross-model extraction (D067) 也无效——bottleneck 在 traces（同源输入），不在 extractor。Regime-dependent analysis + entropy decomposition 定位效应机制。详见 paper_framing.md。\\n\\n## 当前进展\\n- **阶段**: Research (扩展模型覆盖) + Paper Writing (D067 patch 完成)\\n- **论文**: EMNLP 2026 ARR May 25（~6 天）\\n- **D067 Quality Ladder**: **L1 NULL confirmed** — Qwen3-14B cross 60.29%, Qwen2.5-14B cross 58.33%, self 59.31%, 全在 ±1pp noise 范围\\n- **D066 McNemar**: 0/3 seeds 显著 (p=0.092/0.070/1.0)，claims downgraded to directional trend\\n- **D065 Entropy**: 高 entropy 问题是 SICA 效应所在，方向因 regime 而异\\n- **Paper Agent**: D067 bidirectional cross-model evidence 已整合 analysis/discussion/appendix/limitations/conclusion\\n\\n## GPU 实验\\n| ID | 实验 | Server/GPU | 目的 | 状态 |\\n|----|------|-----------|------|------|\\n| exp-059 | Qwen3-14B → Mistral traces | 25068 cuda:0 | Quality Ladder L1a | **DONE** 60.29%, Δ=+4.41pp vs SC (+0.98pp vs self = noise) |\\n| exp-060 | Qwen2.5-14B → Mistral traces | 25068 cuda:1 | Quality Ladder L1b | **DONE** 58.33%, Δ=+2.45pp vs SC (-0.98pp vs self = noise) |\\n| exp-061 | Qwen2.5-7B FOLIO K=12 T=0.7 | 25068 cuda:2 | R4-C3: 第二 Goldilocks 候选 | **RUNNING** ETA ~08:49 UTC |\\n| exp-062 | Gemma-3-27B FOLIO K=12 T=0.7 | 25068 cuda:3 | 新模型家族覆盖 | 磁盘清理中 |\\n| exp-063 | LLaMA-3.1-8B FOLIO K=12 T=0.7 | 16639 cuda:0 | Meta 架构覆盖 | **RUNNING** ETA ~5h |\\n| exp-040 | Qwen3-14B PW-600 | 16639 cuda:1 | Table 1 扩展 | **RUNNING** ~482/600 |\\n| exp-048 | LLaMA-8B PW-600 | 16639 cuda:3 | Table 1 扩展 | **RUNNING** ~245/600 |\\n| DeepSeek-R1-8B | FOLIO-204 | 16639 cuda:2 | 推理模型覆盖 | 待部署 |\\n\\n## 论文写作完成度\\n- [x] D064 数值全文更新\\n- [x] D065 entropy subsection\\n- [x] D066 p-value/claim 全文替换\\n- [x] D067 cross-model bidirectional evidence (analysis/discussion/appendix/limitations/conclusion)\\n- [x] Qwen3 remediation Δ 符号修正 (-0.49)\\n- [x] exp-039 加入 Table 1 + cascade\\n- [x] StrategyQA 脚注\\n- [x] Cross-table 一致性审核 PASS\\n- [ ] Figure 2/3 重新生成（需最终数据）— R4-M5\\n- [ ] 新模型结果加入 Table 1（exp-061/062/063 完成后）\\n- [ ] Submit to Review team\\n\\n## 近期任务（优先级排序）\\n1. [ ] exp-061 完成 → 分析 SC%/Δ → 判断 R4-C3（第二 Goldilocks？）\\n2. [ ] exp-062 磁盘清理 + 部署 Gemma-3-27B\\n3. [ ] DeepSeek-R1-8B 部署 (16639 cuda:2)\\n4. [ ] exp-040/048/063 等待完成\\n5. [ ] 新实验结果加入 Table 1 + paper patch\\n6. [ ] Figure 2/3 regeneration\\n7. [ ] Final review submission\\n\\n## GPU 预算\\n- westd-25068: 4× RTX PRO 6000 — 1/4 running (exp-061), 2/4 freed (exp-059/060 done), 1/4 部署中 (exp-062)\\n- westd-16639: 4× RTX PRO 6000 — 3/4 running (exp-040/048/063), 1/4 待部署 (DeepSeek-R1)\\n\\n## Open Review Issues\\n- **R4-C3** (critical): Goldilocks 1 model×1 dataset → exp-061 是关键实验\\n- **R4-M5** (warning): Figure 2/3 old data → 等最终数据后重生成\\n- **R3-W6** (warning): No 70B+ → 已列为 limitation\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 | 关联实验 |\\n|----|------|------|----------|\\n| D068 | 2026-05-19 | D068: 4-seed replication further weakens Goldilock | exp-067-mistral-folio-seed789, exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456 |\\n| D067 | 2026-05-19 | D067: Quality Ladder L1 null — cross-model extract | exp-059-cross-qwen3-extractor, exp-060-cross-qwen25-14b-extractor, exp-033-mistral-folio204 |\\n| D066 | 2026-05-19 | D066: McNemar 重算后 0/3 seeds 显著 (p=0.092/0.070/1.0) | exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-046-mistral-pw600, exp-039-14b-pw600-16639 |\\n| D065 | 2026-05-19 | D065: Entropy decomposition 不支持 universal selectiv | exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-036-qwen14b-folio204, exp-046-mistral-pw600 |\\n| D064 | 2026-05-19 | D064: 全文采用 D061 修正后 tiebreaking SC 值。Table 1/2/正文全 | exp-033-mistral-folio204, exp-053-mistral-folio204-seed456, exp-027-qwen3-14b-non-thinking |\\n| D063 | 2026-05-19 | D063: Framing 升级 — 从 negative result 到 entropy-con | exp-033-mistral-folio204, exp-026-folio204-trace-regen, exp-052-mistral-folio204-seed123, exp-046-mistral-pw600 |\\n| D062 | 2026-05-19 | D062: κ 数据管线统一为 Option C — raw answers 上的一致性 κ 计算， | exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-027-qwen3-14b-non-thinking, exp-036-z3-feedback-folio204 |\\n| D061 | 2026-05-19 | D061: Table 1 SC tie-breaking 统一为字母序 (75.49%)，Tabl | exp-026-folio204-trace-regen, exp-031-oracle-folio-regen, exp-033-mistral-folio204, exp-046-mistral-pw600 |\\n| D060 | 2026-05-19 | D060: Method improvement 三路失败 — 放弃 method contribu | exp-054-mistral-folio204-t10, exp-055-multitemp-mistral-folio, exp-052-mistral-folio204-seed123, exp-033-mistral-folio204 |\\n| D059 | 2026-05-19 | D059: Scenario 2 确认 — 投 May 25 不变，≥3.0 兜底，启动论文升级策略 | exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-033-mistral-folio204 |\\n\\n\", \"lines\": 76}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c4e603fb-2703-4647-a0f1-96b5b534862a",
  "isSidechain": false,
  "promptId": "62ab6029-0ec6-4d33-8f75-d725e1fbd51a",
  "type": "user",
  "uuid": "f47f48ac-86a6-42b9-8db0-1dd2726d4363",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/ROADMAP.md\\\", \\\"content\\\": \\\"# symb_invariant_consensus — Research Dashboard\\\\n\\\\n> 最后更新: 2026-05-19 08:41 UTC | 更新原因: D067 confirmed, exp-059/060 done, Paper Agent patches complete, ROADMAP refresh\\\\n\\\\n> D067: Quality Ladder L1 NULL confirmed. Cross-model extraction ≈ self-extraction. Bottleneck in traces, not extractor.\\\\n\\\\n## 核心方向\\\\n**Independence Bottleneck Analysis.** Oracle +14.22pp (p<0.001) 证明框架有效，但 self-extraction 仅捕获 24% ceiling。Cross-model extraction (D067) 也无效——bottleneck 在 traces（同源输入），不在 extractor。Regime-dependent analysis + entropy decomposition 定位效应机制。详见 paper_framing.md。\\\\n\\\\n## 当前进展\\\\n- **阶段**: Research (扩展模型覆盖) + Paper Writing (D067 patch 完成)\\\\n- **论文**: EMNLP 2026 ARR May 25（~6 天）\\\\n- **D067 Quality Ladder**: **L1 NULL confirmed** — Qwen3-14B cross 60.29%, Qwen2.5-14B cross 58.33%, self 59.31%, 全在 ±1pp noise 范围\\\\n- **D066 McNemar**: 0/3 seeds 显著 (p=0.092/0.070/1.0)，claims downgraded to directional trend\\\\n- **D065 Entropy**: 高 entropy 问题是 SICA 效应所在，方向因 regime 而异\\\\n- **Paper Agent**: D067 bidirectional cross-model evidence 已整合 analysis/discussion/appendix/limitations/conclusion\\\\n\\\\n## GPU 实验\\\\n| ID | 实验 | Server/GPU | 目的 | 状态 |\\\\n|----|------|-----------|------|------|\\\\n| exp-059 | Qwen3-14B → Mistral traces | 25068 cuda:0 | Quality Ladder L1a | **DONE** 60.29%, Δ=+4.41pp vs SC (+0.98pp vs self = noise) |\\\\n| exp-060 | Qwen2.5-14B → Mistral traces | 25068 cuda:1 | Quality Ladder L1b | **DONE** 58.33%, Δ=+2.45pp vs SC (-0.98pp vs self = noise) |\\\\n| exp-061 | Qwen2.5-7B FOLIO K=12 T=0.7 | 25068 cuda:2 | R4-C3: 第二 Goldilocks 候选 | **RUNNING** ETA ~08:49 UTC |\\\\n| exp-062 | Gemma-3-27B FOLIO K=12 T=0.7 | 25068 cuda:3 | 新模型家族覆盖 | 磁盘清理中 |\\\\n| exp-063 | LLaMA-3.1-8B FOLIO K=12 T=0.7 | 16639 cuda:0 | Meta 架构覆盖 | **RUNNING** ETA ~5h |\\\\n| exp-040 | Qwen3-14B PW-600 | 16639 cuda:1 | Table 1 扩展 | **RUNNING** ~482/600 |\\\\n| exp-048 | LLaMA-8B PW-600 | 16639 cuda:3 | Table 1 扩展 | **RUNNING** ~245/600 |\\\\n| DeepSeek-R1-8B | FOLIO-204 | 16639 cuda:2 | 推理模型覆盖 | 待部署 |\\\\n\\\\n## 论文写作完成度\\\\n- [x] D064 数值全文更新\\\\n- [x] D065 entropy subsection\\\\n- [x] D066 p-value/claim 全文替换\\\\n- [x] D067 cross-model bidirectional evidence (analysis/discussion/appendix/limitations/conclusion)\\\\n- [x] Qwen3 remediation Δ 符号修正 (-0.49)\\\\n- [x] exp-039 加入 Table 1 + cascade\\\\n- [x] StrategyQA 脚注\\\\n- [x] Cross-table 一致性审核 PASS\\\\n- [ ] Figure 2/3 重新生成（需最终数据）— R4-M5\\\\n- [ ] 新模型结果加入 Table 1（exp-061/062/063 完成后）\\\\n- [ ] Submit to Review team\\\\n\\\\n## 近期任务（优先级排序）\\\\n1. [ ] exp-061 完成 → 分析 SC%/Δ → 判断 R4-C3（第二 Goldilocks？）\\\\n2. [ ] exp-062 磁盘清理 + 部署 Gemma-3-27B\\\\n3. [ ] DeepSeek-R1-8B 部署 (16639 cuda:2)\\\\n4. [ ] exp-040/048/063 等待完成\\\\n5. [ ] 新实验结果加入 Table 1 + paper patch\\\\n6. [ ] Figure 2/3 regeneration\\\\n7. [ ] Final review submission\\\\n\\\\n## GPU 预算\\\\n- westd-25068: 4× RTX PRO 6000 — 1/4 running (exp-061), 2/4 freed (exp-059/060 done), 1/4 部署中 (exp-062)\\\\n- westd-16639: 4× RTX PRO 6000 — 3/4 running (exp-040/048/063), 1/4 待部署 (DeepSeek-R1)\\\\n\\\\n## Open Review Issues\\\\n- **R4-C3** (critical): Goldilocks 1 model×1 dataset → exp-061 是关键实验\\\\n- **R4-M5** (warning): Figure 2/3 old data → 等最终数据后重生成\\\\n- **R3-W6** (warning): No 70B+ → 已列为 limitation\\\\n\\\\n## 关键决策日志\\\\n\\\\n| ID | 日期 | 摘要 | 关联实验 |\\\\n|----|------|------|----------|\\\\n| D068 | 2026-05-19 | D068: 4-seed replication further weakens Goldilock | exp-067-mistral-folio-seed789, exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456 |\\\\n| D067 | 2026-05-19 | D067: Quality Ladder L1 null — cross-model extract | exp-059-cross-qwen3-extractor, exp-060-cross-qwen25-14b-extractor, exp-033-mistral-folio204 |\\\\n| D066 | 2026-05-19 | D066: McNemar 重算后 0/3 seeds 显著 (p=0.092/0.070/1.0) | exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-046-mistral-pw600, exp-039-14b-pw600-16639 |\\\\n| D065 | 2026-05-19 | D065: Entropy decomposition 不支持 universal selectiv | exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-036-qwen14b-folio204, exp-046-mistral-pw600 |\\\\n| D064 | 2026-05-19 | D064: 全文采用 D061 修正后 tiebreaking SC 值。Table 1/2/正文全 | exp-033-mistral-folio204, exp-053-mistral-folio204-seed456, exp-027-qwen3-14b-non-thinking |\\\\n| D063 | 2026-05-19 | D063: Framing 升级 — 从 negative result 到 entropy-con | exp-033-mistral-folio204, exp-026-folio204-trace-regen, exp-052-mistral-folio204-seed123, exp-046-mistral-pw600 |\\\\n| D062 | 2026-05-19 | D062: κ 数据管线统一为 Option C — raw answers 上的一致性 κ 计算， | exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-027-qwen3-14b-non-thinking, exp-036-z3-feedback-folio204 |\\\\n| D061 | 2026-05-19 | D061: Table 1 SC tie-breaking 统一为字母序 (75.49%)，Tabl | exp-026-folio204-trace-regen, exp-031-oracle-folio-regen, exp-033-mistral-folio204, exp-046-mistral-pw600 |\\\\n| D060 | 2026-05-19 | D060: Method improvement 三路失败 — 放弃 method contribu | exp-054-mistral-folio204-t10, exp-055-multitemp-mistral-folio, exp-052-mistral-folio204-seed123, exp-033-mistral-folio204 |\\\\n| D059 | 2026-05-19 | D059: Scenario 2 确认 — 投 May 25 不变，≥3.0 兜底，启动论文升级策略 | exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-033-mistral-folio204 |\\\\n\\\\n\\\", \\\"lines\\\": 76}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/ROADMAP.md\", \"content\": \"# symb_invariant_consensus — Research Dashboard\\n\\n> 最后更新: 2026-05-19 08:41 UTC | 更新原因: D067 confirmed, exp-059/060 done, Paper Agent patches complete, ROADMAP refresh\\n\\n> D067: Quality Ladder L1 NULL confirmed. Cross-model extraction ≈ self-extraction. Bottleneck in traces, not extractor.\\n\\n## 核心方向\\n**Independence Bottleneck Analysis.** Oracle +14.22pp (p<0.001) 证明框架有效，但 self-extraction 仅捕获 24% ceiling。Cross-model extraction (D067) 也无效——bottleneck 在 traces（同源输入），不在 extractor。Regime-dependent analysis + entropy decomposition 定位效应机制。详见 paper_framing.md。\\n\\n## 当前进展\\n- **阶段**: Research (扩展模型覆盖) + Paper Writing (D067 patch 完成)\\n- **论文**: EMNLP 2026 ARR May 25（~6 天）\\n- **D067 Quality Ladder**: **L1 NULL confirmed** — Qwen3-14B cross 60.29%, Qwen2.5-14B cross 58.33%, self 59.31%, 全在 ±1pp noise 范围\\n- **D066 McNemar**: 0/3 seeds 显著 (p=0.092/0.070/1.0)，claims downgraded to directional trend\\n- **D065 Entropy**: 高 entropy 问题是 SICA 效应所在，方向因 regime 而异\\n- **Paper Agent**: D067 bidirectional cross-model evidence 已整合 analysis/discussion/appendix/limitations/conclusion\\n\\n## GPU 实验\\n| ID | 实验 | Server/GPU | 目的 | 状态 |\\n|----|------|-----------|------|------|\\n| exp-059 | Qwen3-14B → Mistral traces | 25068 cuda:0 | Quality Ladder L1a | **DONE** 60.29%, Δ=+4.41pp vs SC (+0.98pp vs self = noise) |\\n| exp-060 | Qwen2.5-14B → Mistral traces | 25068 cuda:1 | Quality Ladder L1b | **DONE** 58.33%, Δ=+2.45pp vs SC (-0.98pp vs self = noise) |\\n| exp-061 | Qwen2.5-7B FOLIO K=12 T=0.7 | 25068 cuda:2 | R4-C3: 第二 Goldilocks 候选 | **RUNNING** ETA ~08:49 UTC |\\n| exp-062 | Gemma-3-27B FOLIO K=12 T=0.7 | 25068 cuda:3 | 新模型家族覆盖 | 磁盘清理中 |\\n| exp-063 | LLaMA-3.1-8B FOLIO K=12 T=0.7 | 16639 cuda:0 | Meta 架构覆盖 | **RUNNING** ETA ~5h |\\n| exp-040 | Qwen3-14B PW-600 | 16639 cuda:1 | Table 1 扩展 | **RUNNING** ~482/600 |\\n| exp-048 | LLaMA-8B PW-600 | 16639 cuda:3 | Table 1 扩展 | **RUNNING** ~245/600 |\\n| DeepSeek-R1-8B | FOLIO-204 | 16639 cuda:2 | 推理模型覆盖 | 待部署 |\\n\\n## 论文写作完成度\\n- [x] D064 数值全文更新\\n- [x] D065 entropy subsection\\n- [x] D066 p-value/claim 全文替换\\n- [x] D067 cross-model bidirectional evidence (analysis/discussion/appendix/limitations/conclusion)\\n- [x] Qwen3 remediation Δ 符号修正 (-0.49)\\n- [x] exp-039 加入 Table 1 + cascade\\n- [x] StrategyQA 脚注\\n- [x] Cross-table 一致性审核 PASS\\n- [ ] Figure 2/3 重新生成（需最终数据）— R4-M5\\n- [ ] 新模型结果加入 Table 1（exp-061/062/063 完成后）\\n- [ ] Submit to Review team\\n\\n## 近期任务（优先级排序）\\n1. [ ] exp-061 完成 → 分析 SC%/Δ → 判断 R4-C3（第二 Goldilocks？）\\n2. [ ] exp-062 磁盘清理 + 部署 Gemma-3-27B\\n3. [ ] DeepSeek-R1-8B 部署 (16639 cuda:2)\\n4. [ ] exp-040/048/063 等待完成\\n5. [ ] 新实验结果加入 Table 1 + paper patch\\n6. [ ] Figure 2/3 regeneration\\n7. [ ] Final review submission\\n\\n## GPU 预算\\n- westd-25068: 4× RTX PRO 6000 — 1/4 running (exp-061), 2/4 freed (exp-059/060 done), 1/4 部署中 (exp-062)\\n- westd-16639: 4× RTX PRO 6000 — 3/4 running (exp-040/048/063), 1/4 待部署 (DeepSeek-R1)\\n\\n## Open Review Issues\\n- **R4-C3** (critical): Goldilocks 1 model×1 dataset → exp-061 是关键实验\\n- **R4-M5** (warning): Figure 2/3 old data → 等最终数据后重生成\\n- **R3-W6** (warning): No 70B+ → 已列为 limitation\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 | 关联实验 |\\n|----|------|------|----------|\\n| D068 | 2026-05-19 | D068: 4-seed replication further weakens Goldilock | exp-067-mistral-folio-seed789, exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456 |\\n| D067 | 2026-05-19 | D067: Quality Ladder L1 null — cross-model extract | exp-059-cross-qwen3-extractor, exp-060-cross-qwen25-14b-extractor, exp-033-mistral-folio204 |\\n| D066 | 2026-05-19 | D066: McNemar 重算后 0/3 seeds 显著 (p=0.092/0.070/1.0) | exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-046-mistral-pw600, exp-039-14b-pw600-16639 |\\n| D065 | 2026-05-19 | D065: Entropy decomposition 不支持 universal selectiv | exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-036-qwen14b-folio204, exp-046-mistral-pw600 |\\n| D064 | 2026-05-19 | D064: 全文采用 D061 修正后 tiebreaking SC 值。Table 1/2/正文全 | exp-033-mistral-folio204, exp-053-mistral-folio204-seed456, exp-027-qwen3-14b-non-thinking |\\n| D063 | 2026-05-19 | D063: Framing 升级 — 从 negative result 到 entropy-con | exp-033-mistral-folio204, exp-026-folio204-trace-regen, exp-052-mistral-folio204-seed123, exp-046-mistral-pw600 |\\n| D062 | 2026-05-19 | D062: κ 数据管线统一为 Option C — raw answers 上的一致性 κ 计算， | exp-033-mistral-folio204, exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-027-qwen3-14b-non-thinking, exp-036-z3-feedback-folio204 |\\n| D061 | 2026-05-19 | D061: Table 1 SC tie-breaking 统一为字母序 (75.49%)，Tabl | exp-026-folio204-trace-regen, exp-031-oracle-folio-regen, exp-033-mistral-folio204, exp-046-mistral-pw600 |\\n| D060 | 2026-05-19 | D060: Method improvement 三路失败 — 放弃 method contribu | exp-054-mistral-folio204-t10, exp-055-multitemp-mistral-folio, exp-052-mistral-folio204-seed123, exp-033-mistral-folio204 |\\n| D059 | 2026-05-19 | D059: Scenario 2 确认 — 投 May 25 不变，≥3.0 兜底，启动论文升级策略 | exp-052-mistral-folio204-seed123, exp-053-mistral-folio204-seed456, exp-033-mistral-folio204 |\\n\\n\", \"lines\": 76}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "c4e603fb-2703-4647-a0f1-96b5b534862a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
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
  "lastPrompt": "[CRON] 实验进程异常退出（失败），需要你诊断原因。 详情: Process exited without valid W&B metrics  - exp_id: exp-069-llama8b-logiqa200 - project: symb_invariant_consensus - server: westd-16639",
  "leafUuid": "f47f48ac-86a6-42b9-8db0-1dd2726d4363",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327"
}
```

---

### Runtime record

_source line 23_

```json
{
  "type": "ai-title",
  "aiTitle": "Diagnose W&B metrics missing from experiment exit",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327"
}
```

---

### Assistant

_source line 24 · 2026-05-19T14:32:39.091Z_

<details><summary>Logged reasoning block</summary>

```text
Let me now read the specific experiment exp-069-llama8b-logiqa200 from the registry to understand its full details, and also read the on-experiment-failed skill.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f47f48ac-86a6-42b9-8db0-1dd2726d4363",
  "isSidechain": false,
  "requestId": "req_011CbC6DrwYhSKjukXr3oo2o",
  "type": "assistant",
  "uuid": "da42f677-6618-4a12-9471-2e3f394946f2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J88Ww3q6wYFyV86Wf4xdXb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6756,
      "cache_read_input_tokens": 40442,
      "output_tokens": 373,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6756,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 373,
          "cache_read_input_tokens": 40442,
          "cache_creation_input_tokens": 6756,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6756
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

_source line 25 · 2026-05-19T14:32:40.084Z_

初始化完成。现在读取失败实验的详细信息和 on-experiment-failed skill。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "da42f677-6618-4a12-9471-2e3f394946f2",
  "isSidechain": false,
  "requestId": "req_011CbC6DrwYhSKjukXr3oo2o",
  "type": "assistant",
  "uuid": "6efcee93-4508-4851-8064-2d20ef7acd68",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J88Ww3q6wYFyV86Wf4xdXb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6756,
      "cache_read_input_tokens": 40442,
      "output_tokens": 373,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6756,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 373,
          "cache_read_input_tokens": 40442,
          "cache_creation_input_tokens": 6756,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6756
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

_source line 26 · 2026-05-19T14:32:41.115Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_018NxqLnpJJawLRRuymunLY1`</summary>

```json
{
  "project": "symb_invariant_consensus",
  "filters": {
    "exp_id": "exp-069-llama8b-logiqa200"
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
  "parentUuid": "6efcee93-4508-4851-8064-2d20ef7acd68",
  "isSidechain": false,
  "requestId": "req_011CbC6DrwYhSKjukXr3oo2o",
  "type": "assistant",
  "uuid": "7af831f7-9674-4d45-b9fc-607537cac80f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J88Ww3q6wYFyV86Wf4xdXb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6756,
      "cache_read_input_tokens": 40442,
      "output_tokens": 373,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6756,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 373,
          "cache_read_input_tokens": 40442,
          "cache_creation_input_tokens": 6756,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6756
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

_source line 27 · 2026-05-19T14:32:42.564Z_

<details><summary>↩ Tool result · `toolu_01HZy9U2SrLF5nBMfCF9nR9Q`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__get_project_resource_usage"
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
  "parentUuid": "2d2d4ce9-d9be-438a-afff-e4d373054aa1",
  "isSidechain": false,
  "promptId": "62ab6029-0ec6-4d33-8f75-d725e1fbd51a",
  "type": "user",
  "uuid": "33fb60b9-a615-405b-bdc8-7dcc609854a7",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__get_project_resource_usage",
      "mcp__agent-ml-research__save_project_file"
    ],
    "query": "select:mcp__agent-ml-research__get_project_resource_usage,mcp__agent-ml-research__save_project_file",
    "total_deferred_tools": 82
  },
  "sourceToolAssistantUUID": "2d2d4ce9-d9be-438a-afff-e4d373054aa1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-19T14:32:41.393Z_

<details><summary>↩ Tool result · `toolu_018NxqLnpJJawLRRuymunLY1`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.2611}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7af831f7-9674-4d45-b9fc-607537cac80f",
  "isSidechain": false,
  "promptId": "62ab6029-0ec6-4d33-8f75-d725e1fbd51a",
  "type": "user",
  "uuid": "f983a5ce-a48b-4a26-ab99-2f49f579790c",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.2611}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.2611}}"
    }
  },
  "sourceToolAssistantUUID": "7af831f7-9674-4d45-b9fc-607537cac80f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-19T14:32:41.690Z_

<details open><summary>🔧 Tool call — Read · `toolu_01EPsJeYM7rrKoiq8KLhpahL`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/skills/on-experiment-failed.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f983a5ce-a48b-4a26-ab99-2f49f579790c",
  "isSidechain": false,
  "requestId": "req_011CbC6DrwYhSKjukXr3oo2o",
  "type": "assistant",
  "uuid": "7cc5c723-6fcc-4d4c-89a0-2c336967e903",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J88Ww3q6wYFyV86Wf4xdXb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6756,
      "cache_read_input_tokens": 40442,
      "output_tokens": 373,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6756,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 373,
          "cache_read_input_tokens": 40442,
          "cache_creation_input_tokens": 6756,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6756
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

_source line 30 · 2026-05-19T14:32:41.703Z_

<details><summary>↩ Tool result · reported error · `toolu_01EPsJeYM7rrKoiq8KLhpahL`</summary>

```text
File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7cc5c723-6fcc-4d4c-89a0-2c336967e903",
  "isSidechain": false,
  "promptId": "62ab6029-0ec6-4d33-8f75-d725e1fbd51a",
  "type": "user",
  "uuid": "beebf280-9d3c-4928-ac1d-754d8aa64fbf",
  "toolUseResult": "Error: File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1.",
  "sourceToolAssistantUUID": "7cc5c723-6fcc-4d4c-89a0-2c336967e903",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-19T14:32:42.561Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01HZy9U2SrLF5nBMfCF9nR9Q`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__get_project_resource_usage,mcp__agent-ml-research__save_project_file",
  "max_results": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "beebf280-9d3c-4928-ac1d-754d8aa64fbf",
  "isSidechain": false,
  "requestId": "req_011CbC6DrwYhSKjukXr3oo2o",
  "type": "assistant",
  "uuid": "2d2d4ce9-d9be-438a-afff-e4d373054aa1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J88Ww3q6wYFyV86Wf4xdXb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6756,
      "cache_read_input_tokens": 40442,
      "output_tokens": 373,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 6756,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 373,
          "cache_read_input_tokens": 40442,
          "cache_creation_input_tokens": 6756,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 6756
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

_source line 32 · 2026-05-19T14:32:42.587Z_

```json
{
  "parentUuid": "33fb60b9-a615-405b-bdc8-7dcc609854a7",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "579ed6e6-70f9-4994-bea6-09e665789da0",
  "timestamp": "2026-05-19T14:32:42.587Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 33 · 2026-05-19T14:32:45.843Z_

<details><summary>Logged reasoning block</summary>

```text
The registry filter by exp_id returned 0 results. Let me try searching with a different approach - maybe the exp_id format is slightly different. Let me search the registry output file for this experiment.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "579ed6e6-70f9-4994-bea6-09e665789da0",
  "isSidechain": false,
  "requestId": "req_011CbC6EPZnoLn3rcAZx9hpR",
  "type": "assistant",
  "uuid": "888a8855-c802-4718-8b73-f13ea720987b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Gg2Us4QXtxB6RUCXcXHtYJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1102,
      "cache_read_input_tokens": 47198,
      "output_tokens": 458,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1102,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 458,
          "cache_read_input_tokens": 47198,
          "cache_creation_input_tokens": 1102,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1102
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

_source line 34 · 2026-05-19T14:32:46.923Z_

Registry 过滤没返回结果，可能 exp_id 格式不同。让我搜索一下。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "888a8855-c802-4718-8b73-f13ea720987b",
  "isSidechain": false,
  "requestId": "req_011CbC6EPZnoLn3rcAZx9hpR",
  "type": "assistant",
  "uuid": "83d6a236-a44d-48e5-b508-260061c3e0cf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Gg2Us4QXtxB6RUCXcXHtYJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1102,
      "cache_read_input_tokens": 47198,
      "output_tokens": 458,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1102,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 458,
          "cache_read_input_tokens": 47198,
          "cache_creation_input_tokens": 1102,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1102
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

_source line 35 · 2026-05-19T14:32:51.148Z_

<details open><summary>🔧 Tool call — Bash · `toolu_019dhRzVjAuXz3AhfzPwekKp`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus--claude-sessions-agent-6d4dc7e1/e0fe2496-1882-439a-bfe8-1bec5fa0e327/tool-results/mcp-agent-ml-research-read_registry-1779201145663.txt | python3 -c \"import json,sys; d=json.load(sys.stdin); r=json.loads(d['result']); exps=r['data']['experiments']; matches=[k for k in exps if 'llama8b-logiqa' in k or '069-llama' in k]; print(matches); [print(json.dumps(exps[m], indent=2)) for m in matches]\"",
  "description": "Search registry for exp-069-llama8b-logiqa200"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "83d6a236-a44d-48e5-b508-260061c3e0cf",
  "isSidechain": false,
  "requestId": "req_011CbC6EPZnoLn3rcAZx9hpR",
  "type": "assistant",
  "uuid": "e8355413-26aa-46ab-b95c-f821dbab486f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Gg2Us4QXtxB6RUCXcXHtYJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1102,
      "cache_read_input_tokens": 47198,
      "output_tokens": 458,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1102,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 458,
          "cache_read_input_tokens": 47198,
          "cache_creation_input_tokens": 1102,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1102
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

_source line 36 · 2026-05-19T14:32:51.674Z_

<details><summary>↩ Tool result · `toolu_01J4Sjz3LuZ5A3shEhw135Va`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "223dc552-bb48-47ec-8e03-1a14e38b1515",
  "isSidechain": false,
  "promptId": "62ab6029-0ec6-4d33-8f75-d725e1fbd51a",
  "type": "user",
  "uuid": "d2e50f06-36f1-42f9-9db5-9d80b5f2d9f6",
  "toolUseResult": {
    "filenames": [],
    "durationMs": 39,
    "numFiles": 0,
    "truncated": false
  },
  "sourceToolAssistantUUID": "223dc552-bb48-47ec-8e03-1a14e38b1515",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 37 · 2026-05-19T14:32:51.305Z_

<details><summary>↩ Tool result · `toolu_019dhRzVjAuXz3AhfzPwekKp`</summary>

```text
['exp-069-llama8b-logiqa200']
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-19T11:40:15.817Z",
  "updated_at": "2026-05-19T14:32:06.439Z",
  "hypothesis": "LLaMA-3.1-8B-Instruct \u5728 LogiQA-200 \u4e0a SICA vs SC\u3002FOLIO-204 \u4e0a LLaMA-8B SC=66.18% delta=-4.41pp (exp-063, negative/error amplification)\u3002LogiQA \u4e0a Mistral-7B SC=51% delta=+0.5pp (exp-049b)\uff0cQwen2.5-14B SC=78.5% delta=-0.50pp (exp-038)\u3002\u6d4b\u8bd5 LLaMA-8B \u5728 LogiQA \u4e0a\u7684 regime\uff08SC \u9884\u8ba1 50-60%\uff0c\u53ef\u80fd\u5728 error amplification zone\uff09\u3002parent=exp-063-llama8b-folio204-16639",
  "parent": "exp-063-llama8b-folio204-16639",
  "spec": {
    "command": "python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8012/v1 --model auto --seed 42 --strategyqa-data data/logiqa_200.json --folio-data data/empty.json --math-data data/empty.json --pw-data data/empty.json --output results/exp069_llama8b_logiqa200/exp069_results.json --save-intermediates",
    "server": "westd-16639",
    "gpu": "cuda:2",
    "port": 8012,
    "data_path": "data/logiqa_200.json",
    "data_count": 200,
    "model_name": "Meta-Llama-3.1-8B-Instruct",
    "seed": 42
  },
  "notes": "\u8bca\u65ad 2026-05-19T20:17: westd-16639 \u4e0a\u8fd0\u884c\u6b63\u5e38\u3002tmux_session=exp-069-llama8b-logiqa200, vLLM via nohup (\u975e tmux), run PID=152414, vLLM PID=151829 (EngineCore on GPU2). port=8012, CUDA_VISIBLE_DEVICES=2. \u8fdb\u5ea6: 12/200 (6%), \u521a\u542f\u52a8\u7ea612\u5206\u949f\u3002GPU2 \u5229\u7528\u7387 96%, \u663e\u5b58 88254/97887 MiB\u3002vLLM model=/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct, max-model-len=8192\u3002\u540c\u673a\u5176\u4ed6\u5b9e\u9a8c: exp-048(GPU3,457/600), exp-064(GPU0,74/204), exp-068(GPU1,121/200)\u3002",
  "failure_reason": "process dead 5\u00d7 with no sentinel/W&B \u2014 auto-resolved as failed",
  "conclusion": "failed",
  "completed_at": "",
  "reproduce": {
    "finished_at": "2026-05-19T14:32:03.443Z"
  },
  "extra": {
    "hook_events": [
      {
        "event": "on_failed",
        "action": "agent",
        "ts": "2026-05-19T14:32:09.270208+00:00"
      }
    ]
  }
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e8355413-26aa-46ab-b95c-f821dbab486f",
  "isSidechain": false,
  "promptId": "62ab6029-0ec6-4d33-8f75-d725e1fbd51a",
  "type": "user",
  "uuid": "9db5a5fa-3f06-4c62-9a1a-c30c1b916654",
  "toolUseResult": {
    "stdout": "['exp-069-llama8b-logiqa200']\n{\n  \"status\": \"DONE\",\n  \"retry_count\": 0,\n  \"created_at\": \"2026-05-19T11:40:15.817Z\",\n  \"updated_at\": \"2026-05-19T14:32:06.439Z\",\n  \"hypothesis\": \"LLaMA-3.1-8B-Instruct \\u5728 LogiQA-200 \\u4e0a SICA vs SC\\u3002FOLIO-204 \\u4e0a LLaMA-8B SC=66.18% delta=-4.41pp (exp-063, negative/error amplification)\\u3002LogiQA \\u4e0a Mistral-7B SC=51% delta=+0.5pp (exp-049b)\\uff0cQwen2.5-14B SC=78.5% delta=-0.50pp (exp-038)\\u3002\\u6d4b\\u8bd5 LLaMA-8B \\u5728 LogiQA \\u4e0a\\u7684 regime\\uff08SC \\u9884\\u8ba1 50-60%\\uff0c\\u53ef\\u80fd\\u5728 error amplification zone\\uff09\\u3002parent=exp-063-llama8b-folio204-16639\",\n  \"parent\": \"exp-063-llama8b-folio204-16639\",\n  \"spec\": {\n    \"command\": \"python -u run_full_mvp.py --mode vllm --k 12 --temperature 0.7 --max-tokens 4096 --api-base http://localhost:8012/v1 --model auto --seed 42 --strategyqa-data data/logiqa_200.json --folio-data data/empty.json --math-data data/empty.json --pw-data data/empty.json --output results/exp069_llama8b_logiqa200/exp069_results.json --save-intermediates\",\n    \"server\": \"westd-16639\",\n    \"gpu\": \"cuda:2\",\n    \"port\": 8012,\n    \"data_path\": \"data/logiqa_200.json\",\n    \"data_count\": 200,\n    \"model_name\": \"Meta-Llama-3.1-8B-Instruct\",\n    \"seed\": 42\n  },\n  \"notes\": \"\\u8bca\\u65ad 2026-05-19T20:17: westd-16639 \\u4e0a\\u8fd0\\u884c\\u6b63\\u5e38\\u3002tmux_session=exp-069-llama8b-logiqa200, vLLM via nohup (\\u975e tmux), run PID=152414, vLLM PID=151829 (EngineCore on GPU2). port=8012, CUDA_VISIBLE_DEVICES=2. \\u8fdb\\u5ea6: 12/200 (6%), \\u521a\\u542f\\u52a8\\u7ea612\\u5206\\u949f\\u3002GPU2 \\u5229\\u7528\\u7387 96%, \\u663e\\u5b58 88254/97887 MiB\\u3002vLLM model=/root/autodl-tmp/models/Meta-Llama-3.1-8B-Instruct, max-model-len=8192\\u3002\\u540c\\u673a\\u5176\\u4ed6\\u5b9e\\u9a8c: exp-048(GPU3,457/600), exp-064(GPU0,74/204), exp-068(GPU1,121/200)\\u3002\",\n  \"failure_reason\": \"process dead 5\\u00d7 with no sentinel/W&B \\u2014 auto-resolved as failed\",\n  \"conclusion\": \"failed\",\n  \"completed_at\": \"\",\n  \"reproduce\": {\n    \"finished_at\": \"2026-05-19T14:32:03.443Z\"\n  },\n  \"extra\": {\n    \"hook_events\": [\n      {\n        \"event\": \"on_failed\",\n        \"action\": \"agent\",\n        \"ts\": \"2026-05-19T14:32:09.270208+00:00\"\n      }\n    ]\n  }\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "e8355413-26aa-46ab-b95c-f821dbab486f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-19T14:32:51.632Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01J4Sjz3LuZ5A3shEhw135Va`</summary>

```json
{
  "pattern": "**/on-experiment-failed*",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9db5a5fa-3f06-4c62-9a1a-c30c1b916654",
  "isSidechain": false,
  "requestId": "req_011CbC6EPZnoLn3rcAZx9hpR",
  "type": "assistant",
  "uuid": "223dc552-bb48-47ec-8e03-1a14e38b1515",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/.claude/sessions/agent_6d4dc7e1",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Gg2Us4QXtxB6RUCXcXHtYJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1102,
      "cache_read_input_tokens": 47198,
      "output_tokens": 458,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1102,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 458,
          "cache_read_input_tokens": 47198,
          "cache_creation_input_tokens": 1102,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1102
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

_source line 39_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[CRON] 实验进程异常退出（失败），需要你诊断原因。 详情: Process exited without valid W&B metrics  - exp_id: exp-069-llama8b-logiqa200 - project: symb_invariant_consensus - server: westd-16639",
  "leafUuid": "d2e50f06-36f1-42f9-9db5-9d80b5f2d9f6",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327"
}
```

---

### Runtime record

_source line 40_

```json
{
  "type": "ai-title",
  "aiTitle": "Diagnose W&B metrics missing from experiment exit",
  "sessionId": "e0fe2496-1882-439a-bfe8-1bec5fa0e327"
}
```

---
