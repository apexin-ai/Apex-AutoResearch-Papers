# research westb1 experiment proposal

**How Pruning Criteria Shape Post-RLVR Recovery: A Controlled Study of Structured MLP Pruning in a Reasoning LLM** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 61
- **Recorded user turns:** 1
- **Tool calls:** 20
- **Original source:** `logs/workers/worker_research_westb1_experiment_proposal_20260519T182410.log`
- **Structured JSON:** [`1d304d1c0f110b1f1dab.json`](../../sessions/1d/1d304d1c0f110b1f1dab.json)

## Before a recorded user message

25 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
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
  "uuid": "5f948156-be05-442a-8b7e-3aaba965872a",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/memory/"
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
    "resetsAt": 1779228600,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "843e9021-d3f9-49d7-89a8-c7a8aedab2f4",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1"
}
```

---

### Assistant

_source line 4_

I'll investigate westb:1 available experiments. Let me gather information in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "baf9de91-4c06-4937-9ebc-4dd9e4ab92c0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JYwYezKLnbQLYng8SLqcs5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12250,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12250
      },
      "output_tokens": 4,
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01SjmTAYn2pVfHGPMz21Z8GT`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "a60d023b-283e-4ede-a668-56f930e83b1b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JYwYezKLnbQLYng8SLqcs5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12250,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12250
      },
      "output_tokens": 4,
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

_source line 6 · 2026-05-19T18:24:26.271Z_

<details><summary>↩ Tool result · `toolu_01SjmTAYn2pVfHGPMz21Z8GT`</summary>

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
  "tool_name": "mcp__agent-ml-research__read_registry"
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "82784075-00d6-4d39-81fb-62f6d35355ee",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_project_file"
    ],
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file",
    "total_deferred_tools": 29
  }
}
```

</details>

---

### Assistant

_source line 7_

<details><summary>Logged reasoning block</summary>

```text
Let me gather information in parallel: check checkpoints on westb, read the registry, and check for relevant files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "6a89dd8b-5903-41bd-a582-ed8a38cc3341",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019gF8jjGZfz4cj4P9LevTfk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1126,
      "cache_read_input_tokens": 24091,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1126
      },
      "output_tokens": 17,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01L64toZKtW5eaproY8E72ia`</summary>

```json
{
  "server": "westb-23072",
  "command": "du -sh /root/autodl-tmp/recovery_aware_struct_prune/*/",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "c151a97f-c0df-470a-a38d-4f07210800fe",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019gF8jjGZfz4cj4P9LevTfk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1126,
      "cache_read_input_tokens": 24091,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1126
      },
      "output_tokens": 17,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01EBwiJdN8c5aJ7MK6yvWhpu`</summary>

```json
{
  "server": "westb-23072",
  "command": "ls /root/recovery_aware_struct_prune/src/",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "f6ea54d1-a31d-40f1-84de-0d4c3d5f7395",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019gF8jjGZfz4cj4P9LevTfk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1126,
      "cache_read_input_tokens": 24091,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1126
      },
      "output_tokens": 17,
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

_source line 10_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01DwkEZ5mbqCmFa2fMKJiZhu`</summary>

```json
{
  "project": "recovery_aware_struct_prune",
  "filters": {
    "status": "DONE"
  },
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "146550a7-fb3d-4350-be68-a3585b0bd52d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019gF8jjGZfz4cj4P9LevTfk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1126,
      "cache_read_input_tokens": 24091,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1126
      },
      "output_tokens": 17,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01846SSPHugcQcfYxSqRXVnP`</summary>

```json
{
  "project": "recovery_aware_struct_prune",
  "file": "ROADMAP.md",
  "max_chars": 12000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "f62ca440-7d4a-4568-b4a9-c4f129366736",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019gF8jjGZfz4cj4P9LevTfk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1126,
      "cache_read_input_tokens": 24091,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1126
      },
      "output_tokens": 17,
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

_source line 12 · 2026-05-19T18:24:34.269Z_

<details><summary>↩ Tool result · `toolu_01L64toZKtW5eaproY8E72ia`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"8.0K\\t/root/autodl-tmp/recovery_aware_struct_prune/artifacts/\\n8.0K\\t/root/autodl-tmp/recovery_aware_struct_prune/eval_results/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_cka_only_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_cka_only_20_1p5b/\\n38G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_cka_only_20_seed123/\\n220K\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_random_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_rasp_20_1p5b/\\n11G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_rasp_25/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_standard_20_1p5b/\\n21M\\t/root/autodl-tmp/recovery_aware_struct_prune/logs/\\n3.4G\\t/root/autodl-tmp/recovery_aware_struct_prune/models/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_cka_only_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_cka_only_20_1p5b/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_random_20/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_20_1p5b/\\n11G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_25/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_rlvr_20/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_standard_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_standard_20_1p5b/\\n11G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_standard_25/\\n22M\\t/root/autodl-tmp/recovery_aware_struct_prune/results/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20_1p5b/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_gradient_20/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_random_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_1p5b/\\n11G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_25/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_rlvr_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b/\\n11G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_25/\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 2.42}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "2b536966-62c0-417f-88c6-5beac9d15b0c",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"8.0K\\\\t/root/autodl-tmp/recovery_aware_struct_prune/artifacts/\\\\n8.0K\\\\t/root/autodl-tmp/recovery_aware_struct_prune/eval_results/\\\\n12G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_cka_only_20/\\\\n2.8G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_cka_only_20_1p5b/\\\\n38G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_cka_only_20_seed123/\\\\n220K\\\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_random_20/\\\\n2.8G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_rasp_20_1p5b/\\\\n11G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_rasp_25/\\\\n2.8G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_standard_20_1p5b/\\\\n21M\\\\t/root/autodl-tmp/recovery_aware_struct_prune/logs/\\\\n3.4G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/models/\\\\n12G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_cka_only_20/\\\\n2.8G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_cka_only_20_1p5b/\\\\n12G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_random_20/\\\\n12G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_20/\\\\n2.8G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_20_1p5b/\\\\n11G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_25/\\\\n12G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_rlvr_20/\\\\n12G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_standard_20/\\\\n2.8G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_standard_20_1p5b/\\\\n11G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_standard_25/\\\\n22M\\\\t/root/autodl-tmp/recovery_aware_struct_prune/results/\\\\n12G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20/\\\\n2.8G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20_1p5b/\\\\n12G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_gradient_20/\\\\n12G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_random_20/\\\\n2.8G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_1p5b/\\\\n11G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_25/\\\\n12G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_rlvr_20/\\\\n2.8G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b/\\\\n11G\\\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_25/\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 2.42}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"8.0K\\t/root/autodl-tmp/recovery_aware_struct_prune/artifacts/\\n8.0K\\t/root/autodl-tmp/recovery_aware_struct_prune/eval_results/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_cka_only_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_cka_only_20_1p5b/\\n38G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_cka_only_20_seed123/\\n220K\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_random_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_rasp_20_1p5b/\\n11G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_rasp_25/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/grpo_standard_20_1p5b/\\n21M\\t/root/autodl-tmp/recovery_aware_struct_prune/logs/\\n3.4G\\t/root/autodl-tmp/recovery_aware_struct_prune/models/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_cka_only_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_cka_only_20_1p5b/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_random_20/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_20_1p5b/\\n11G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_25/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_rasp_rlvr_20/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_standard_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_standard_20_1p5b/\\n11G\\t/root/autodl-tmp/recovery_aware_struct_prune/pruned_standard_25/\\n22M\\t/root/autodl-tmp/recovery_aware_struct_prune/results/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20_1p5b/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_gradient_20/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_random_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_1p5b/\\n11G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_25/\\n12G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_rlvr_20/\\n2.8G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_1p5b/\\n11G\\t/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_25/\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 2.42}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-19T18:24:35.186Z_

<details><summary>↩ Tool result · `toolu_01EBwiJdN8c5aJ7MK6yvWhpu`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"__pycache__\\nbenchmark_inference.py\\ncka_overlap.py\\ncka_overlap.py.bak\\ncompute_layer_cka.py\\nconvert_graspune_to_hf.py\\ncorrelation_analysis.py\\ncorrelation_analysis.py.bak\\ndebug_extract.py\\neval_gsm8k.py\\neval_humaneval.py\\neval_math500.py\\neval_mbpp.py\\nextract_cka_for_figures.py\\nextract_pruning_pattern.py\\ngradient_flow_analysis.py\\ngrasp_scoring.py\\nimportance_score.py\\nimportance_score.py.bak\\nmeasure_inference_speed.py\\nmodel_utils.py\\nplot_cka_figures.py\\nplot_cka_heatmap.py\\nprune.py\\nprune.py.bak\\nprune.py.bak2\\nprune_unstructured.py\\nrasp_scoring.py\\nrun_alpha_ablation.sh\\nrun_cka_reliability.py\\nrun_eval_25.sh\\nrun_extended_eval.sh\\nrun_full_eval.sh\\nrun_full_eval_all.sh\\nrun_full_eval_d008.sh\\nrun_full_eval_d008_parallel.sh\\nrun_grasp_prune.sh\\nrun_graspune.sh\\nrun_grpo_multiseed.sh\\nrun_grpo_stage2.sh\\nrun_grpo_v4.sh\\nrun_multi_seed_rasp.sh\\nrun_mvp.sh\\nrun_mvp_resume.sh\\nrun_mvp_resume_from_3_5.sh\\nrun_post_recovery_eval.sh\\nrun_remaining_ablation.sh\\nrun_scoring_ablation.sh\\nrun_scoring_ablation_continue.sh\\nrun_sft_eval.sh\\nrun_sft_warmup.sh\\nrun_unstructured_baseline.py\\nsft_recovery.py\\ntrain_grpo.py\\ntrain_grpo.py.bak\\ntrain_grpo_v3.py\\ntrain_grpo_v4.py\\ntrain_grpo_v5.py\\ntrain_sft_warmup.py\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.88}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "d4f5ae36-6ce7-481f-8211-6c1c81b31485",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"__pycache__\\\\nbenchmark_inference.py\\\\ncka_overlap.py\\\\ncka_overlap.py.bak\\\\ncompute_layer_cka.py\\\\nconvert_graspune_to_hf.py\\\\ncorrelation_analysis.py\\\\ncorrelation_analysis.py.bak\\\\ndebug_extract.py\\\\neval_gsm8k.py\\\\neval_humaneval.py\\\\neval_math500.py\\\\neval_mbpp.py\\\\nextract_cka_for_figures.py\\\\nextract_pruning_pattern.py\\\\ngradient_flow_analysis.py\\\\ngrasp_scoring.py\\\\nimportance_score.py\\\\nimportance_score.py.bak\\\\nmeasure_inference_speed.py\\\\nmodel_utils.py\\\\nplot_cka_figures.py\\\\nplot_cka_heatmap.py\\\\nprune.py\\\\nprune.py.bak\\\\nprune.py.bak2\\\\nprune_unstructured.py\\\\nrasp_scoring.py\\\\nrun_alpha_ablation.sh\\\\nrun_cka_reliability.py\\\\nrun_eval_25.sh\\\\nrun_extended_eval.sh\\\\nrun_full_eval.sh\\\\nrun_full_eval_all.sh\\\\nrun_full_eval_d008.sh\\\\nrun_full_eval_d008_parallel.sh\\\\nrun_grasp_prune.sh\\\\nrun_graspune.sh\\\\nrun_grpo_multiseed.sh\\\\nrun_grpo_stage2.sh\\\\nrun_grpo_v4.sh\\\\nrun_multi_seed_rasp.sh\\\\nrun_mvp.sh\\\\nrun_mvp_resume.sh\\\\nrun_mvp_resume_from_3_5.sh\\\\nrun_post_recovery_eval.sh\\\\nrun_remaining_ablation.sh\\\\nrun_scoring_ablation.sh\\\\nrun_scoring_ablation_continue.sh\\\\nrun_sft_eval.sh\\\\nrun_sft_warmup.sh\\\\nrun_unstructured_baseline.py\\\\nsft_recovery.py\\\\ntrain_grpo.py\\\\ntrain_grpo.py.bak\\\\ntrain_grpo_v3.py\\\\ntrain_grpo_v4.py\\\\ntrain_grpo_v5.py\\\\ntrain_sft_warmup.py\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.88}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"__pycache__\\nbenchmark_inference.py\\ncka_overlap.py\\ncka_overlap.py.bak\\ncompute_layer_cka.py\\nconvert_graspune_to_hf.py\\ncorrelation_analysis.py\\ncorrelation_analysis.py.bak\\ndebug_extract.py\\neval_gsm8k.py\\neval_humaneval.py\\neval_math500.py\\neval_mbpp.py\\nextract_cka_for_figures.py\\nextract_pruning_pattern.py\\ngradient_flow_analysis.py\\ngrasp_scoring.py\\nimportance_score.py\\nimportance_score.py.bak\\nmeasure_inference_speed.py\\nmodel_utils.py\\nplot_cka_figures.py\\nplot_cka_heatmap.py\\nprune.py\\nprune.py.bak\\nprune.py.bak2\\nprune_unstructured.py\\nrasp_scoring.py\\nrun_alpha_ablation.sh\\nrun_cka_reliability.py\\nrun_eval_25.sh\\nrun_extended_eval.sh\\nrun_full_eval.sh\\nrun_full_eval_all.sh\\nrun_full_eval_d008.sh\\nrun_full_eval_d008_parallel.sh\\nrun_grasp_prune.sh\\nrun_graspune.sh\\nrun_grpo_multiseed.sh\\nrun_grpo_stage2.sh\\nrun_grpo_v4.sh\\nrun_multi_seed_rasp.sh\\nrun_mvp.sh\\nrun_mvp_resume.sh\\nrun_mvp_resume_from_3_5.sh\\nrun_post_recovery_eval.sh\\nrun_remaining_ablation.sh\\nrun_scoring_ablation.sh\\nrun_scoring_ablation_continue.sh\\nrun_sft_eval.sh\\nrun_sft_warmup.sh\\nrun_unstructured_baseline.py\\nsft_recovery.py\\ntrain_grpo.py\\ntrain_grpo.py.bak\\ntrain_grpo_v3.py\\ntrain_grpo_v4.py\\ntrain_grpo_v5.py\\ntrain_sft_warmup.py\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.88}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-19T18:24:38.064Z_

<details><summary>↩ Tool result · `toolu_01DwkEZ5mbqCmFa2fMKJiZhu`</summary>

```text
Error: result (156,760 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "5407e57a-527e-4acd-afe7-f3bde4164966",
  "tool_use_result": {
    "content": "Error: result (156,760 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"eval_mbpp_grpo_rasp_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T18:18:35.729Z\", \"updated_at\": \"2026-05-19T18:24:28.539Z\", \"hypothesis\": \"MBPP pass@1 eval on GRPO RASP 20% model @2048. Dense baseline=53.48% (200/374). RASP GRPO GSM8K=60.88%, HumanEval=10.37%. Tests RASP GRPO code generation on MBPP. Completes MBPP 3×2 matrix. Expected: between CKA-only GRPO (14.17%) and Standard GRPO (running). Recovery gradient on MBPP validates C2 capability breadth claim on second code benchmark.\", \"conclusion\": \"failed\"}, \"eval_mbpp_sft_rasp_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T18:18:34.640Z\", \"updated_at\": \"2026-05-19T18:23:21.466Z\", \"hypothesis\": \"MBPP pass@1 eval on SFT RASP 20% model @2048. Dense baseline=53.48% (200/374). RASP SFT GSM8K=60.88% (post-GRPO), HumanEval SFT=10.37%. Tests whether RASP SFT preserves code capability on MBPP. Part of MBPP 3×2 matrix (3 methods × SFT/GRPO) for C2 capability breadth claim. Expected: between CKA-only SFT and Standard SFT.\", \"conclusion\": \"failed\", \"notes\": \"Model not found on westb. 7B SFT RASP checkpoint is on westd (sft_rasp_20_westd), not westb. Need to rerun on westd when GPU available.\"}, \"eval_mbpp_grpo_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:41:07.213Z\", \"updated_at\": \"2026-05-19T18:17:54.178Z\", \"hypothesis\": \"MBPP pass@1 eval on GRPO CKA-only 20% model @2048. Dense baseline=53.48% (200/374). CKA-only GRPO showed strongest recovery on GSM8K (64.37%) and HumanEval (20.12%). If MBPP follows same pattern (CKA-only > Standard > RASP), confirms capability breadth claim (C2) generalizes to second code benchmark. Compare with parallel eval_mbpp_grpo_standard_20 and eval_mbpp_sft_cka_only_20.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1417, \"n_correct\": 53, \"n_total\": 374, \"stderr\": 0.018}}, \"eval_gsm8k_grpo_shortgpt_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T17:19:18.419Z\", \"updated_at\": \"2026-05-19T18:17:53.164Z\", \"hypothesis\": \"GSM8K eval on ShortGPT GRPO checkpoint-100. ShortGPT SFT=44.73%, if GRPO improves significantly it suggests depth-pruned models can still benefit from RL. If minimal improvement or collapse, confirms coarse layer removal limits GRPO recovery capacity vs fine-grained methods (CKA-only 64.37%, Standard 59.44%).\", \"parent\": \"grpo_shortgpt_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 43.37, \"n_correct\": 572, \"n_total\": 1319, \"stderr\": 0.0136}}, \"eval_gsm8k_sft_shortgpt_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T15:47:16.122Z\", \"updated_at\": \"2026-05-19T18:03:15.831Z\", \"hypothesis\": \"ShortGPT SFT checkpoint GSM8K eval. After depth pruning (5/28 layers removed by Block Influence scoring) + SFT warmup (loss=0.62, token_accuracy=0.83), measure GSM8K accuracy. Compare with fine-grained pruning SFT results: CKA-only SFT ~60%, Standard SFT ~64%. ShortGPT expected lower due to coarse layer removal destroying more representations.\", \"parent\": \"sft_shortgpt_20\", \"conclusion\": \"success\", \"metrics\": {\"gsm8k_accuracy\": 44.73, \"n_correct\": 590, \"n_total\": 1319}}, \"grpo_shortgpt_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T16:04:46.243Z\", \"updated_at\": \"2026-05-19T18:02:50.896Z\", \"hypothesis\": \"GRPO recovery on ShortGPT depth-pruned model (5/28 layers removed by BI scoring, 15.3% sparsity). After SFT warmup (loss=0.62). Tests whether coarse layer removal (ShortGPT) leads to lower GRPO recovery than fine-grained structural pruning (CKA-only 64.37%, Standard 59.44%, RASP 60.88%). Expected to show collapse or severe stagnation because removing entire layers destroys more distributed representations needed for RL training.\", \"parent\": \"sft_shortgpt_20\", \"conclusion\": \"failed\", \"notes\": \"checkpoint-100 model intact, can be used for eval. Crash was torch serialization error, not model corruption.\"}, \"sft_shortgpt_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:22:26.084Z\", \"updated_at\": \"2026-05-19T18:02:48.590Z\", \"hypothesis\": \"ShortGPT depth pruning (20%, 5/28 layers removed) after SFT warmup will show lower recovery capacity than fine-grained structural pruning methods (Standard/CKA-only/RASP) because coarse layer removal destroys more distributed representations needed for GRPO recovery. Layers removed: [15,16,17,24,25], actual param sparsity 15.30%.\", \"conclusion\": \"success\"}, \"eval_gsm8k_grpo_cka_only_20_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T17:47:34.008Z\", \"updated_at\": \"2026-05-19T17:48:24.627Z\", \"hypothesis\": \"GSM8K eval on GRPO CKA-only 20% seed123 checkpoint. Tests reproducibility of CKA-only GRPO GSM8K performance (original seed42 = 64.37%). If seed123 matches closely, confirms CKA-only GRPO advantage is robust across seeds.\", \"parent\": \"grpo_cka_only_20_seed123\", \"metrics\": {\"accuracy\": 0.6422, \"stderr\": 0.0132, \"n_correct\": 847, \"n_total\": 1319, \"eos_rate\": 0.9909, \"avg_response_length\": 195.97, \"natural_eos\": 1307, \"truncated\": 12}, \"conclusion\": \"success\"}, \"eval_humaneval_grpo_standard_20_1p5b_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T11:35:48.029Z\", \"updated_at\": \"2026-05-19T17:02:50.370Z\", \"hypothesis\": \"1.5B GRPO Standard HumanEval pass@1 @2048. Cross-scale validation baseline. 7B GRPO Standard HumanEval failed (multiple attempts). If 1.5B Standard also shows weak code generation after GRPO (vs CKA-only), strengthens claim that standard pruning loses broader capabilities.\", \"conclusion\": \"success\"}, \"gradient_flow_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T15:03:16.535Z\", \"updated_at\": \"2026-05-19T16:38:41.269Z\", \"hypothesis\": \"CKA-only pruned models exhibit significantly stronger gradient signals (per-layer L2 norm) compared to Standard and RASP, with statistical significance (Wilcoxon p<0.05). This gradient magnitude difference is consistent with CKA-only's superior GRPO recovery capacity.\", \"conclusion\": \"success\", \"metrics\": {\"cka_only_mean_grad_norm\": 0.3229, \"standard_mean_grad_norm\": 0.1118, \"rasp_mean_grad_norm\": 0.1431, \"cka_vs_standard_ratio\": 2.89, \"rasp_vs_standard_ratio\": 1.28, \"cka_vs_standard_significant_layers\": \"55/56\", \"cka_vs_rasp_significant_layers\": \"56/56\", \"rasp_vs_standard_significant_layers\": \"45/56\", \"rasp_vs_standard_nonsig_layers\": \"layer_18_mlp,layer_19_attn,layer_19_mlp,layer_20_attn,layer_20_mlp,layer_21_attn,layer_21_mlp,layer_22_attn,layer_24_mlp,layer_27_attn,layer_27_mlp\", \"n_samples\": 200, \"statistical_test\": \"Wilcoxon signed-rank, per-layer\", \"bootstrap_n\": 1000, \"seed\": 42}}, \"eval_humaneval_sft_standard_20_2048_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T10:05:36.497Z\", \"updated_at\": \"2026-05-19T16:26:41.948Z\", \"hypothesis\": \"SFT Standard 20% HumanEval pass@1 @2048. Uses current sft_standard_20 model on westd-29022 (same model as MATH-500 eval at 25.8%). Fills SFT×method HumanEval matrix. Compare with GRPO Standard fair (~10% interim) and SFT CKA-only (~24% interim).\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1341, \"stderr\": 0.0266, \"n_correct\": 22, \"n_total\": 164, \"avg_response_length\": 1809.1, \"median_response_length\": 2048}}, \"eval_humaneval_sft_cka_only_20_1p5b_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T11:32:47.965Z\", \"updated_at\": \"2026-05-19T16:26:40.886Z\", \"hypothesis\": \"1.5B SFT CKA-only HumanEval pass@1 @2048. Cross-scale validation of capability breadth claim. 7B SFT CKA-only result: failed (pass@1=0). Testing whether 1.5B scale shows different pattern, as SFT alone may not activate code generation capability regardless of pruning criterion.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.0061, \"stderr\": 0.0061, \"n_correct\": 1, \"n_total\": 164, \"avg_response_length\": 1968.8, \"median_response_length\": 2048}}, \"eval_humaneval_grpo_cka_only_20_1p5b_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T11:32:50.649Z\", \"updated_at\": \"2026-05-19T16:26:38.696Z\", \"hypothesis\": \"1.5B GRPO CKA-only HumanEval pass@1 @2048. Cross-scale validation of capability breadth claim. 7B result: pass@1=20.12%. If 1.5B CKA-only also shows strong code generation after GRPO (>> Standard/RASP), strengthens cross-scale evidence that CKA-based pruning preserves broader capability spectrum.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0, \"stderr\": 0, \"n_correct\": 0, \"n_total\": 164, \"avg_response_length\": 1977.7, \"median_response_length\": 2048}}, \"eval_gsm8k_grpo_rasp_20_fair\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T12:47:37.399Z\", \"updated_at\": \"2026-05-19T16:17:16.053Z\", \"hypothesis\": \"GRPO RASP 20% fair (v5 config) GSM8K 全量评估。RASP 结合 recovery-awareness 与 structural pruning，预期性能介于 Standard (59.44%) 和 CKA-only (64.37%) 之间。若 RASP ≈ Standard，说明 recovery-awareness 的增益主要来自 CKA 信号而非 RASP 的混合策略。N=1319。\", \"parent\": \"eval_gsm8k_grpo_standard_20_fair_v2\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.6088, \"stderr\": 0.0134, \"n_correct\": 803, \"n_total\": 1319, \"eos_rate\": 0.9879, \"avg_response_length\": 195.7}, \"notes\": \"Cron false positive: eval脚本不走W&B误判failed。实际 accuracy=60.88% (803/1319)。RASP 介于 Standard (59.44%) 和 CKA-only (64.37%) 之间，更靠近 Standard。RASP-Standard gap=1.44pp, CKA-RASP gap=3.49pp。recovery-awareness 增益主要来自 CKA 信号。\"}, \"eval_mbpp_dense_unpruned\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T13:47:53.814Z\", \"updated_at\": \"2026-05-19T16:17:00.452Z\", \"hypothesis\": \"Dense unpruned DeepSeek-R1-Distill-Qwen-7B MBPP pass@1 baseline @2048. Establishes ceiling performance for MBPP code generation. All pruned models' MBPP results will be compared against this baseline.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.5348, \"stderr\": 0.0258, \"n_correct\": 200, \"n_total\": 374}, \"notes\": \"Cron false positive: eval脚本不走W&B，进程正常退出后cron检测不到指标误判failed。实际 pass@1=53.48% (200/374), stderr=0.0258。Dense baseline for MBPP.\"}, \"eval_humaneval_sft_rasp_20_2048_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T13:18:20.664Z\", \"updated_at\": \"2026-05-19T15:47:14.846Z\", \"hypothesis\": \"SFT RASP 20% HumanEval pass@1 @2048. Fills RASP SFT cell in HumanEval matrix. GRPO RASP = 10.98%. If SFT RASP ≈ GRPO RASP, confirms redistribution-not-expansion pattern holds for RASP too. Compare with CKA-only SFT=GRPO=20.12%.\", \"parent\": \"eval_humaneval_sft_rasp_20_2048\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1037, \"stderr\": 0.0238, \"n_correct\": 17, \"n_total\": 164, \"avg_response_length\": 1253.7, \"median_response_length\": 2048}}, \"grpo_cka_only_20_seed123\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T09:27:11.294Z\", \"updated_at\": \"2026-05-19T15:21:17.415Z\", \"hypothesis\": \"Multi-seed validation (seed=123) of CKA-only 20% GRPO training. If CKA-only advantage holds across seeds, strengthens C1 claim that pruning criteria determine recovery capacity. Seed 42 result: 64.37% GSM8K.\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.1361, \"final_step_loss\": 0.05054, \"final_reward\": 0.2975, \"final_reward_std\": 0.4097, \"train_steps\": 100, \"train_runtime_hours\": 11.63, \"wandb_run\": \"j8kn0sqd\"}}, \"gradient_flow_analysis\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:44:25.606Z\", \"updated_at\": \"2026-05-19T14:45:13.584Z\", \"hypothesis\": \"CKA-only pruned models exhibit stronger gradient flow (higher per-layer gradient norms) compared to Standard pruned models, enabling more effective GRPO recovery. Standard pruning creates weaker gradient signals that limit training effectiveness.\", \"conclusion\": \"success\", \"metrics\": {\"cka_only_attn_grad_mean\": 0.3135, \"cka_only_attn_grad_cv\": 1.2231, \"cka_only_mlp_grad_mean\": 0.285, \"cka_only_mlp_grad_cv\": 1.2424, \"standard_attn_grad_mean\": 0.1316, \"standard_attn_grad_cv\": 1.1363, \"standard_mlp_grad_mean\": 0.1222, \"standard_mlp_grad_cv\": 1.1489, \"grad_magnitude_ratio_attn\": 2.38, \"grad_magnitude_ratio_mlp\": 2.33}}, \"cka_calibration_stability_ablation\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:21:15.548Z\", \"updated_at\": \"2026-05-19T14:32:43.647Z\", \"hypothesis\": \"CKA-based functional overlap scores F(h) are stable across calibration sizes (256/512/1024 samples), with Spearman rho > 0.95 between any two sizes. This validates that our pruning criterion is not sensitive to calibration hyperparameter.\", \"conclusion\": \"success\", \"metrics\": {\"split_half_rho\": 0.9932, \"n_splits\": 5, \"size_sensitivity_128\": 0.982, \"size_sensitivity_256\": 0.989, \"size_sensitivity_512\": 0.995}}, \"eval_humaneval_grpo_standard_20_fair_2048_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T07:05:14.343Z\", \"updated_at\": \"2026-05-19T14:20:25.129Z\", \"hypothesis\": \"GRPO stage2 with standard 20% fair pruning recovers meaningful code generation ability on HumanEval, demonstrating that the fair pruning strategy preserves code-critical layers better than CKA-only pruning.\", \"notes\": \"2026-05-19 19:06 progress check: 156/164 (95.1%), interim pass@1 ~0.1143 at problem 140. ~15min remaining.\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1098, \"n_correct\": 18, \"n_total\": 164}}, \"eval_humaneval_sft_standard_20_2048_v4\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:01:09.628Z\", \"updated_at\": \"2026-05-19T14:12:28.675Z\", \"hypothesis\": \"7B SFT Standard 20% HumanEval pass@1 @2048 v4 retry. Completes SFT column of 7B HumanEval matrix. Compare with GRPO Standard 10.98% and SFT CKA-only 20.12%. v3 failed due to process crash.\", \"parent\": \"eval_humaneval_sft_standard_20_2048_v3\", \"conclusion\": \"killed\"}, \"eval_humaneval_sft_rasp_20_2048_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T13:59:19.821Z\", \"updated_at\": \"2026-05-19T14:02:42.064Z\", \"hypothesis\": \"7B SFT RASP 20% HumanEval pass@1 @2048 v3 retry. Completes SFT column of 7B HumanEval matrix. Compare with GRPO RASP 10.98% and SFT CKA-only 20.12%. v2 failed due to startup issue.\", \"parent\": \"eval_humaneval_sft_rasp_20_2048\", \"conclusion\": \"killed\"}, \"eval_humaneval_sft_standard_20_1p5b_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T11:35:45.876Z\", \"updated_at\": \"2026-05-19T13:54:06.392Z\", \"hypothesis\": \"1.5B SFT Standard HumanEval pass@1 @2048 on westb. Cross-scale validation of capability breadth claim. Running on westb cuda:0 where checkpoints already exist (no scp needed).\", \"metrics\": {\"pass_at_1\": 0.0061, \"n_correct\": 1, \"n_total\": 164, \"stderr\": 0.0061}, \"conclusion\": \"success\"}, \"eval_humaneval_sft_cka_only_20_2048_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T09:27:07.470Z\", \"updated_at\": \"2026-05-19T13:22:29.762Z\", \"hypothesis\": \"SFT CKA-only HumanEval v2 (PATH bug 修复版重跑)，验证 v1 的 0% 是否为假结果。v1 因 eval_humaneval.py 用裸 python 导致 164 题全部 sandbox 失败。修复后用 sys.executable 重跑。\", \"parent\": \"eval_humaneval_sft_cka_only_20_2048\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 20.12, \"n_correct\": 33, \"n_total\": 164}}, \"eval_math500_grpo_cka_only_20_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:36:14.421Z\", \"updated_at\": \"2026-05-19T13:08:18.617Z\", \"hypothesis\": \"GRPO CKA-only 20% MATH-500 accuracy with explicit max_new_tokens=2048. Re-eval for fair C1 OOD comparison: previous eval (26.6%) did not specify max_new_tokens. SFT CKA-only @2048 = 29.0%. If GRPO < SFT on MATH-500, C1 decoupling shows GRPO benefit is benchmark-dependent.\", \"parent\": \"eval_math500_grpo_cka_only_20\", \"metrics\": {\"accuracy\": 0.292, \"n_correct\": 146, \"n_total\": 500}, \"conclusion\": \"success\"}, \"eval_math500_sft_standard_20_2048_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T01:34:44.782Z\", \"updated_at\": \"2026-05-19T13:08:16.850Z\", \"hypothesis\": \"SFT Standard 20% MATH-500 @2048 with correct GSM8K-trained model (retrained on westd). Fair C1 comparison with GRPO Standard @2048. Previous attempt used wrong model (sft_qwen_math_standard_20).\", \"parent\": \"eval_math500_sft_standard_20\", \"metrics\": {\"accuracy\": 0.258, \"n_correct\": 129, \"n_total\": 500}, \"conclusion\": \"success\"}, \"eval_gsm8k_sft_standard_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:10:55.912Z\", \"updated_at\": \"2026-05-19T13:07:57.786Z\", \"hypothesis\": \"1.5B Standard post-SFT GSM8K accuracy (N=1319). SFT baseline for computing GRPO delta on Standard pruning at 1.5B scale. Compare with GRPO Standard 1.5B (22.29%) to quantify GRPO benefit. Completes 3-method SFT vs GRPO comparison at 1.5B.\", \"metrics\": {\"accuracy\": 0.22896133434420016, \"n_correct\": 302, \"n_total\": 1319}, \"conclusion\": \"success\"}, \"eval_gsm8k_grpo_standard_20_fair_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T09:27:09.334Z\", \"updated_at\": \"2026-05-19T12:47:36.437Z\", \"hypothesis\": \"验证 Standard GRPO fair (v5 config: beta=0.01, temp=0.4, maxlen=1024, DAPO, lr=1e-6) 的 GSM8K 准确率。替换 phantom 58.91% (从未被实际验证过的数字)。使用 grpo_stage2_standard_20_fair checkpoint, N=1319。\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 59.44, \"n_correct\": 784, \"n_total\": 1319}}, \"eval_humaneval_grpo_rasp_20_fair_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T06:38:59.146Z\", \"updated_at\": \"2026-05-19T09:44:43.320Z\", \"hypothesis\": \"HumanEval pass@1 for GRPO RASP 20% (fair model) with max_new_tokens=2048. Fair model trained with same setup as Standard/CKA-only for unbiased comparison on code generation.\", \"parent\": \"grpo_stage2_rasp_20_fair\", \"conclusion\": \"success\", \"metrics\": {\"pass_at_1\": 0.1098, \"n_correct\": 18, \"n_total\": 164, \"stderr\": 0.0244, \"avg_response_length\": null}}, \"eval_gsm8k_grpo_unstructured_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T04:46:38.286Z\", \"updated_at\": \"2026-05-19T08:05:04.224Z\", \"hypothesis\": \"GSM8K accuracy for GRPO-recovered unstructured 20% pruned model. Pre-GRPO baseline was 87.87%. Compare with structured GRPO results (CKA-only 64.37%, Standard 58.91%, RASP 56.71%) to quantify structured vs unstructured recovery dynamics.\", \"parent\": \"grpo_unstructured_20\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.8764, \"n_correct\": 1156, \"n_total\": 1319, \"stderr\": 0.00906, \"eos_rate\": 0.9818, \"truncated\": 24, \"avg_response_length\": 600}}, \"eval_humaneval_sft_cka_only_20_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T07:01:47.646Z\", \"updated_at\": \"2026-05-19T07:36:57.077Z\", \"metrics\": {\"pass_at_1\": 0, \"n_correct\": 0, \"n_total\": 164}, \"conclusion\": \"failed\", \"hypothesis\": \"SFT with CKA-only importance at 20% pruning ratio destroys code generation ability because CKA alone cannot identify layers critical for structured reasoning, resulting in near-zero HumanEval pass@1.\"}, \"eval_humaneval_grpo_cka_only_20_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T04:11:28.637Z\", \"updated_at\": \"2026-05-19T07:36:55.239Z\", \"hypothesis\": \"GRPO recovery training on CKA-only 20% pruned model recovers code generation ability on HumanEval from SFT baseline of 0% pass@1, because CKA-only preserves structural similarity that GRPO can exploit for cross-task recovery\", \"parent\": \"grpo_cka_only_20\", \"metrics\": {\"pass_at_1\": 0.2012, \"n_correct\": 33, \"n_total\": 164, \"stderr\": 0.0313, \"avg_response_length\": 1523.31, \"median_response_length\": 2048, \"wall_clock_seconds\": 11933}, \"conclusion\": \"success\"}, \"eval_humaneval_grpo_standard_20_fair_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T05:59:46.295Z\", \"updated_at\": \"2026-05-19T07:09:37.173Z\", \"hypothesis\": \"HumanEval pass@1 for GRPO Standard 20% (fair model) with max_new_tokens=2048. Previous eval used non-fair checkpoint (grpo_stage2_standard_20_v8, pass@1=10.37%). Fair model trained with same setup as CKA-only/RASP for unbiased comparison. Compare with SFT Standard @2048 (11.59%) and other pruning methods to verify recovery gradient on code generation.\", \"conclusion\": \"failed\", \"metrics\": {\"error\": \"model path not found: /root/autodl-tmp/recovery_aware_struct_prune/grpo_standard_20_fair — correct path is grpo_stage2_standard_20_fair\"}}, \"eval_humaneval_grpo_standard_20_fair_2048_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T06:39:01.302Z\", \"updated_at\": \"2026-05-19T06:42:53.032Z\", \"hypothesis\": \"HumanEval pass@1 for GRPO Standard 20% (fair model) with max_new_tokens=2048. Retry of v1 which failed due to wrong path (grpo_standard_20_fair vs grpo_stage2_standard_20_fair). Fair comparison with CKA-only/RASP.\", \"parent\": \"eval_humaneval_grpo_standard_20_fair_2048\", \"conclusion\": \"failed\"}, \"grpo_standard_20_fair\": {\"created_at\": \"2026-05-18T01:05:44.644Z\", \"hypothesis\": \"GRPO recovery training on standard-pruned 20% model (fair v5 config: beta=0.01, dapo loss, format_reward=0.1, temp=0.4, rep_penalty=1.15, adamw_bnb_8bit). Tests whether standard pruning + GRPO can recover GSM8K reasoning. Part of 4-method fair comparison (CKA-only, Standard, RASP, Random) under identical GRPO v4 config.\", \"parent\": \"grpo_rasp_20_fair\", \"status\": \"DONE\", \"updated_at\": \"2026-05-19T06:39:34.930Z\", \"metrics\": {\"wandb_run_id\": \"tyv20u2k\", \"total_steps\": 100, \"runtime_seconds\": 3017, \"reward_trajectory\": [0.051, 0.056, 0.067, 0.081, 0.019, 0.043, 0.047, 0.046, 0.031, 0.054], \"frac_zero_std_trajectory\": [0.5, 0.625, 0.5, 0.5, 0.575, 0.55, 0.575, 0.55, 0.55, 0.55], \"peak_reward\": 0.081, \"peak_reward_step\": 40, \"final_reward\": 0.054, \"final_frac_zero_std\": 0.55, \"dynamics_pattern\": \"dip_then_partial_recovery\", \"dip_step\": 50, \"dip_reward\": 0.019}, \"conclusion\": \"success\", \"notes\": \"Standard shows stagnation pattern: reward flat 0.03-0.08 全程无上升趋势, frac_zero_std stuck 0.5-0.55. 比 RASP (permanent collapse to 0.01 reward, frac_zero_std→0.85) 略好但也未恢复. 4-way gradient confirmed: CKA-only (active recovery) > Random (plateau) > Standard (stagnation) > RASP (permanent collapse). D058 fair comparison 完成.\"}, \"eval_gsm8k_grpo_standard_20_extended_300\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T05:57:41.667Z\", \"updated_at\": \"2026-05-19T05:58:27.139Z\", \"metrics\": {\"accuracy\": 0.5929, \"n_correct\": 782, \"n_total\": 1319, \"eos_rate\": 0.9795, \"avg_response_length\": 229.57, \"stderr\": 0.01353}, \"conclusion\": \"negative\", \"hypothesis\": \"Standard pruning 20% with extended GRPO training (300 steps) will not recover GSM8K accuracy beyond the 100-step level (~52-53%), because the reward collapse observed during training prevents meaningful downstream improvement regardless of additional training steps.\"}, \"eval_gsm8k_grpo_cka_only_20_extended_300\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T01:42:30.325Z\", \"updated_at\": \"2026-05-19T03:49:12.498Z\", \"hypothesis\": \"Extended GRPO training (300 steps vs 100 steps) on CKA-only 20% pruned model will further improve GSM8K in-distribution accuracy beyond the 64.37% achieved at 100 steps\", \"parent\": \"grpo_cka_only_20_extended_300\", \"metrics\": {\"gsm8k_accuracy\": 0.6437, \"correct\": 849, \"total\": 1319, \"stderr\": 0.0132, \"eos_rate\": 0.9924, \"avg_response_length\": 190.45}, \"conclusion\": \"negative\"}, \"inference_bench_clean_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T01:42:25.421Z\", \"updated_at\": \"2026-05-19T02:44:07.178Z\", \"hypothesis\": \"Clean inference benchmark (Dense + CKA-only 20% + Standard 20%) on isolated GPU. Previous plan_016 benchmark was polluted by GPU contention. Measures per-token throughput and latency for speedup claims. 50 prompts x 256 max_new_tokens, GSM8K test set.\", \"conclusion\": \"success\", \"metrics\": {\"original_tps\": 72.02, \"cka_only_20_tps\": 58.28, \"standard_20_tps\": 58.25, \"cka_only_20_speedup\": 0.809, \"standard_20_speedup\": 0.809, \"original_first_token_ms\": 20.05, \"cka_only_20_first_token_ms\": 16.35, \"standard_20_first_token_ms\": 16.4, \"original_per_token_ms\": 13.89, \"cka_only_20_per_token_ms\": 16.73, \"standard_20_per_token_ms\": 16.71, \"original_params\": 7615616512, \"pruned_params\": 6161946112, \"param_reduction_pct\": 19.1}}, \"eval_gsm8k_sft_rasp_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:10:57.471Z\", \"updated_at\": \"2026-05-19T02:43:38.445Z\", \"hypothesis\": \"1.5B RASP post-SFT GSM8K accuracy (N=1319). SFT baseline for computing GRPO delta on RASP pruning at 1.5B. Compare with GRPO RASP 1.5B (26.16%).\", \"parent\": \"sft_rasp_20_1p5b\", \"metrics\": {\"accuracy\": 0.2691, \"n_correct\": 355, \"n_total\": 1319, \"stderr\": 0.0122, \"grpo_delta_pp\": -0.75}, \"conclusion\": \"success\"}, \"eval_math500_grpo_standard_20_fair_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:24:25.108Z\", \"updated_at\": \"2026-05-19T01:39:52.608Z\", \"hypothesis\": \"Standard 20% post-GRPO (fair v5) MATH-500 accuracy with max_new_tokens=2048. Restart of slow original. Interim Acc@100=36%. Cross-benchmark validation for C1 decoupling claim.\", \"parent\": \"eval_math500_grpo_standard_20_fair\", \"metrics\": {\"accuracy\": 0.264, \"n_correct\": 132, \"n_total\": 500, \"stderr\": 0.0197}, \"conclusion\": \"success\"}, \"eval_math500_sft_rasp_20_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:36:16.836Z\", \"updated_at\": \"2026-05-19T01:39:03.294Z\", \"hypothesis\": \"SFT RASP 20% MATH-500 accuracy with max_new_tokens=2048. Fair comparison with GRPO RASP @2048 (24.0%) for C1 decoupling on MATH-500. SFT recovery should show lower reasoning capability than GRPO recovery on structurally pruned model.\", \"parent\": \"eval_math500_sft_rasp_20\", \"metrics\": {\"accuracy\": 0.226, \"n_correct\": 113, \"n_total\": 500, \"stderr\": 0.0187, \"natural_eos\": 314, \"truncated\": 186, \"natural_eos_pct\": 0.628, \"avg_response_length\": 930.58, \"median_response_length\": 274}, \"conclusion\": \"success\"}, \"eval_math500_dense_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:08:58.081Z\", \"updated_at\": \"2026-05-19T01:34:41.598Z\", \"hypothesis\": \"Dense (unpruned) DeepSeek-R1-Distill-Qwen-7B MATH-500 eval with max_new_tokens=2048. Fair comparison baseline for all pruned model MATH-500 evals which also use 2048 max tokens. Previous Dense baseline (73.6%) used 4096 tokens.\", \"parent\": \"eval_math500_dense_unpruned\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.53, \"n_correct\": 265, \"n_total\": 500, \"stderr\": 0.0223, \"natural_eos_pct\": 0.468, \"truncated_pct\": 0.532, \"avg_response_length\": 1724.5, \"median_response_length\": 2048}}, \"eval_math500_grpo_rasp_20_fair\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:16:25.616Z\", \"updated_at\": \"2026-05-18T23:53:54.384Z\", \"hypothesis\": \"GRPO RASP 20% pruned model on MATH-500 with max_new_tokens=2048. Fair comparison for C1 decoupling: GRPO recovery on RASP-pruned model should show different accuracy profile compared to SFT recovery, measuring reasoning capability after RL-based fine-tuning on structurally pruned model.\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.24, \"n_correct\": 120, \"n_total\": 500, \"stderr\": 0.0191, \"natural_eos_pct\": 0.64, \"truncated_pct\": 0.36, \"avg_response_length\": 903.5, \"median_response_length\": 272, \"max_new_tokens\": 2048}}, \"eval_gsm8k_sft_cka_only_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T17:51:20.577Z\", \"updated_at\": \"2026-05-18T23:46:01.152Z\", \"hypothesis\": \"1.5B CKA-only post-SFT GSM8K accuracy (N=1319). SFT baseline for computing GRPO delta: if GRPO CKA-only 1.5B GSM8K > SFT CKA-only 1.5B GSM8K, GRPO adds value beyond SFT recovery on 1.5B scale. Completes C1 decoupling evidence at 1.5B.\", \"parent\": \"sft_cka_only_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.3563, \"n_correct\": 470, \"n_total\": 1319, \"stderr\": 0.0132, \"eos_rate\": 0.9507, \"avg_response_length\": 336.76}}, \"sft_standard_20_retrain_westd\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:40:50.567Z\", \"updated_at\": \"2026-05-18T23:24:15.076Z\", \"hypothesis\": \"Retrain SFT Standard 20% on westd from pruned_standard_20. Original sft_standard_20 model lost (was on old westd-11672). Needed for eval_math500_sft_standard_20_2048 with correct model.\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.758, \"mean_token_accuracy\": 0.8252, \"train_runtime_sec\": 1688, \"train_samples_per_second\": 8.856, \"epochs\": 2, \"total_steps\": 1870}}, \"eval_math500_sft_standard_20_2048\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:18:30.238Z\", \"updated_at\": \"2026-05-18T23:19:30.781Z\", \"hypothesis\": \"SFT Standard 20% MATH-500 accuracy with max_new_tokens=2048. Fair comparison with GRPO Standard @2048 for C1 decoupling claim on harder benchmark.\", \"parent\": \"eval_math500_sft_standard_20\", \"conclusion\": \"killed\"}, \"eval_gsm8k_grpo_rasp_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T16:59:22.921Z\", \"updated_at\": \"2026-05-18T23:02:00.110Z\", \"hypothesis\": \"1.5B RASP post-GRPO GSM8K accuracy (N=1319). Cross-model generalization: 7B RASP GRPO collapsed (reward 0.01), but 1.5B RASP showed reward=0.099 without collapse. If 1.5B RASP GSM8K is lower than CKA-only but not catastrophically low, confirms scale-dependent recovery dynamics. Completes 3-method 1.5B GSM8K comparison.\", \"parent\": \"grpo_rasp_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.2616, \"n_correct\": 345, \"n_total\": 1319, \"stderr\": 0.0121, \"eos_rate\": 0.9378, \"avg_response_length\": 392.7}}, \"eval_math500_grpo_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T02:41:32.199Z\", \"updated_at\": \"2026-05-18T22:58:51.065Z\", \"hypothesis\": \"CKA-only post-GRPO MATH-500 accuracy. Critical gap: CKA-only is the paper's core method with best GRPO dynamics (peak 0.354), must have post-GRPO MATH-500 data. If GRPO CKA-only > SFT CKA-only on MATH-500, GRPO genuinely helps CKA-only (unlike Standard/RASP). If not, C1 decoupling extends to CKA-only method too.\", \"parent\": \"grpo_cka_only_20\", \"metrics\": {\"accuracy\": 0.266, \"n_correct\": 133, \"n_total\": 500, \"stderr\": 0.0198, \"truncated\": 108, \"truncation_rate\": 0.216, \"avg_response_length\": 1124.24}, \"conclusion\": \"success\"}, \"eval_math500_sft_cka_only_20_v4_restart\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:16:24.171Z\", \"updated_at\": \"2026-05-18T22:12:04.614Z\", \"hypothesis\": \"CKA-only 20% post-SFT MATH-500 accuracy (restart of v4 which had cuda:2 conflict). Full 500 samples, max_new_tokens=2048. Core C1 evidence for decoupling claim.\", \"parent\": \"eval_math500_sft_cka_only_20_v4\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.29, \"n_correct\": 145, \"n_total\": 500, \"stderr\": 0.0203, \"natural_eos\": 384, \"truncated\": 116, \"natural_eos_pct\": 0.768, \"avg_response_length\": 673.278, \"median_response_length\": 242.5}}, \"grpo_cka_only_20_extended_300\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T14:51:36.423Z\", \"updated_at\": \"2026-05-18T21:43:18.847Z\", \"hypothesis\": \"Extended GRPO CKA-only 7B from step 100 to 300. Paired control for E2 Standard extended: if CKA-only continues improving while Standard enters reward desert, proves CKA-only's structural advantage persists under longer training. Standard showed reward decline after step 260 (0.102→0.056); CKA-only's peak at step 100 was 0.354 — expect continued learning.\", \"parent\": \"grpo_cka_only_20\", \"conclusion\": \"success\", \"metrics\": {\"final_reward\": 0.3075, \"peak_reward\": 0.4444, \"peak_reward_step\": 280, \"reward_step100\": 0.354, \"reward_step300\": 0.3075, \"train_loss_final\": 0.0349, \"global_step\": 300, \"runtime_seconds\": 23004, \"gpu_hours\": 6.5, \"final_frac_zero_std\": 0.275, \"reward_range\": [0.22, 0.44], \"pattern\": \"sustained oscillation, no collapse\", \"wandb_run_id\": \"z9f0z901\"}}, \"eval_gsm8k_grpo_standard_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T16:38:01.585Z\", \"updated_at\": \"2026-05-18T21:03:21.558Z\", \"hypothesis\": \"Standard GRPO 1.5B (100 steps, reward=0.084) on GSM8K eval: expect low accuracy (~5-10%) given minimal training, serving as baseline for pruned model comparison.\", \"parent\": \"grpo_standard_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.2229, \"n_correct\": 294, \"n_total\": 1319, \"stderr\": 0.0115}}, \"eval_gsm8k_grpo_cka_only_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T16:35:29.923Z\", \"updated_at\": \"2026-05-18T20:09:40.771Z\", \"hypothesis\": \"1.5B CKA-only post-GRPO GSM8K accuracy (N=1319). Cross-model generalization: 7B CKA-only GRPO achieved 64.37% GSM8K. If 1.5B CKA-only GRPO also leads among pruning methods, confirms scale-invariant recovery capacity gradient. Parent: grpo_cka_only_20_1p5b (reward=0.2375, highest among 1.5B methods).\", \"parent\": \"grpo_cka_only_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.3548, \"n_correct\": 468, \"n_total\": 1319, \"stderr\": 0.0132}}, \"eval_math500_sft_cka_only_20_v4\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T17:05:46.843Z\", \"updated_at\": \"2026-05-18T18:16:11.156Z\", \"hypothesis\": \"CKA-only 20% post-SFT MATH-500 accuracy (full 500 samples). C1 core evidence: compare with GRPO CKA-only MATH-500 to test decoupling. If post-GRPO > post-SFT on MATH-500, CKA-only uniquely benefits from GRPO on harder benchmarks. v3 timed out at 170/500 (36.67% interim). v4 removes timeout, adds --max_new_tokens 2048.\", \"parent\": \"eval_math500_sft_cka_only_20_v3\", \"conclusion\": \"failed\"}, \"eval_math500_dense_unpruned\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T13:42:10.786Z\", \"updated_at\": \"2026-05-18T18:15:28.383Z\", \"hypothesis\": \"Dense unpruned DeepSeek-R1-Distill-Qwen-7B MATH-500 baseline. Establishes upper bound for all pruned model MATH-500 evaluations. Previous result on westd showed 73.6%; this is a verification run on westd-29022.\", \"conclusion\": \"success\", \"metrics\": {\"accuracy\": 0.736, \"stderr\": 0.0197, \"n_correct\": 368, \"n_total\": 500, \"natural_eos_pct\": 0.752}}, \"eval_math500_grpo_standard_20_fair\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T13:38:06.779Z\", \"updated_at\": \"2026-05-18T18:09:33.985Z\", \"hypothesis\": \"Standard 20% post-GRPO MATH-500 accuracy (fair v5 config). Cross-benchmark validation: if Standard GRPO shows same decoupling pattern on MATH-500 as GSM8K (post-GRPO ≈ post-SFT), confirms C1 decoupling is not benchmark-specific.\", \"parent\": \"grpo_standard_20_fair\", \"notes\": \"v1: 126/500 completed (Acc@100=36.0%), killed SIGHUP after 4h44m. v2: restarted with --max_new_tokens 2048, died silently at 19/500 with no error/Traceback/OOM in log. Cron detected process dead 5× → auto-resolved failed. Need diagnostic: check dmesg for OOM killer, GPU memory, tmux session status. Interim data: Acc@100=36.0% from v1.\", \"conclusion\": \"failed\"}, \"eval_math500_sft_cka_only_20_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T13:39:24.314Z\", \"updated_at\": \"2026-05-18T17:04:00.609Z\", \"hypothesis\": \"CKA-only 20% post-SFT MATH-500 accuracy. C1 validation: compare with GRPO CKA-only MATH-500 to test if GRPO genuinely helps CKA-only on harder benchmark. If post-GRPO > post-SFT on MATH-500, CKA-only is unique in benefiting from GRPO (unlike Standard/RASP decoupling).\", \"parent\": \"sft_cka_only_20\", \"conclusion\": \"failed\"}, \"grpo_rasp_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T15:12:41.395Z\", \"updated_at\": \"2026-05-18T16:32:13.529Z\", \"hypothesis\": \"RASP 20% GRPO on 1.5B model. Cross-model generalization: 7B RASP collapsed to reward 0.01, frac_zero_std 0.85. If 1.5B shows same collapse pattern, confirms scale-invariant recovery capacity gradient bottom tier. Completes 3-method 1.5B comparison: CKA-only (reward ~0.26) >> Standard (0.08) >> RASP (expected collapse).\", \"parent\": \"sft_rasp_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"final_reward\": 0.099, \"frac_zero_std\": 0.175, \"clipped_ratio\": 0.82}}, \"grpo_cka_only_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T12:50:08.570Z\", \"updated_at\": \"2026-05-18T16:08:40.491Z\", \"hypothesis\": \"CKA-only 20% GRPO on 1.5B model. Cross-model generalization: if CKA-only's superior GRPO dynamics (peak reward 0.354 on 7B) hold on 1.5B, confirms scale-invariant recovery capacity gradient. Parent: sft_cka_only_20_1p5b.\", \"parent\": \"sft_cka_only_20_1p5b\", \"conclusion\": \"success\", \"metrics\": {\"reward_mean\": 0.2375, \"frac_reward_zero_std\": 0.175, \"loss\": 0.0595, \"kl\": 0.00215, \"grad_norm\": 1.445, \"global_step\": 100, \"note\": \"training completed 100/100 but save_model failed (disk full). checkpoint-100 has complete model.\"}}, \"grpo_standard_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T14:15:13.990Z\", \"updated_at\": \"2026-05-18T15:11:31.870Z\", \"hypothesis\": \"Standard 20% GRPO on 1.5B model. Cross-model generalization: if Standard's dip-then-recovery GRPO dynamics (peak 0.081, dip 0.019 on 7B) hold on 1.5B, confirms scale-invariant recovery capacity gradient. Paired with CKA-only 1.5B GRPO for direct comparison.\", \"parent\": \"sft_standard_20_1p5b\", \"metrics\": {\"reward_mean\": 0.0844, \"frac_reward_zero_std\": 0.15, \"loss\": 0.0151, \"grad_norm\": 4.03125, \"kl\": 0.0044, \"entropy\": 0.4617, \"final_step\": 100, \"max_steps\": 100, \"total_time_min\": 53}, \"conclusion\": \"success\"}, \"grpo_standard_20_extended_300_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T13:53:41.781Z\", \"updated_at\": \"2026-05-18T14:50:59.377Z\", \"hypothesis\": \"Extended GRPO Standard 7B from step 110 to 300 (resumed after disk-full crash at step 120). Tests whether longer GRPO training changes the recovery capacity gradient. save_steps=50, save_total_limit=3 to prevent disk issues.\", \"parent\": \"grpo_standard_20_extended_300\", \"metrics\": {\"reward_mean_step300\": 0.0562, \"loss_step300\": 0.0367, \"frac_reward_zero_std_step300\": 0.525, \"kl_step300\": 0.00306, \"entropy_step300\": 0.157, \"lr_step300\": 3.33e-09, \"runtime_min\": 48, \"reward_decline_after_step260\": true}, \"conclusion\": \"success\"}, \"grpo_standard_20_extended_300\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T13:40:13.842Z\", \"updated_at\": \"2026-05-18T14:47:58.809Z\", \"hypothesis\": \"Extended GRPO Standard 7B from step 100 to 300. Tests whether longer GRPO training changes the recovery capacity gradient — does Standard eventually catch up to CKA-only, or does the gap persist/widen? If gap widens, confirms CKA-guided pruning creates a structural advantage that more training cannot compensate.\", \"parent\": \"grpo_standard_20_fair\", \"conclusion\": \"failed\"}, \"sft_standard_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T12:09:56.278Z\", \"updated_at\": \"2026-05-18T12:31:29.300Z\", \"hypothesis\": \"Standard 20% SFT recovery on 1.5B model. Cross-model generalization test: if Standard SFT recovery pattern holds on 1.5B as on 7B. Paired with CKA-only and RASP 1.5B SFT for cross-scale comparison of recovery capacity gradient.\", \"conclusion\": \"success\"}, \"sft_cka_only_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T11:29:09.842Z\", \"updated_at\": \"2026-05-18T12:31:27.978Z\", \"hypothesis\": \"CKA-only 20% SFT recovery on 1.5B model. Cross-model generalization test: if CKA-only SFT recovery pattern (high accuracy) holds on 1.5B as on 7B, validates that CKA-guided pruning preserves recovery capacity across model scales.\", \"notes\": \"Training completed 1870/1870 steps. Checkpoint save crashed (RuntimeError at inline_container.cc:668) due to disk 100% full. Model weights rescued from checkpoint-1870 (optimizer.pt truncated but model.safetensors intact). Checkpoints cleaned, model files promoted to output dir. Pending load validation.\", \"conclusion\": \"success\"}, \"sft_rasp_20_1p5b\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T12:09:57.178Z\", \"updated_at\": \"2026-05-18T12:29:19.746Z\", \"hypothesis\": \"RASP 20% SFT recovery on 1.5B model. Cross-model generalization test: if RASP SFT recovery pattern holds on 1.5B as on 7B. Paired with CKA-only and Standard 1.5B SFT for cross-scale comparison of recovery capacity gradient.\", \"conclusion\": \"success\"}, \"inference_bench_cka_only_20_clean\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T09:47:42.247Z\", \"updated_at\": \"2026-05-18T10:07:56.924Z\", \"hypothesis\": \"Clean CKA-only inference benchmark (rerun after GPU contention in v1). Validates CKA-only latency/memory vs dense baseline on clean cuda:0. Dense dummy in rasp slot (rasp model not on westb).\", \"parent\": \"inference_bench_cka_only_20\", \"metrics\": {\"dense\": {\"tokens_per_second\": 75.73, \"avg_latency_sec\": 6.729, \"peak_memory_gb\": 16.22, \"total_tokens\": 25477, \"validation\": \"PASS (75.73 vs expected 76.25, <1% deviation)\"}, \"cka_only_20\": {\"tokens_per_second\": 51.86, \"avg_latency_sec\": 4.078, \"peak_memory_gb\": 11.6, \"total_tokens\": 10574, \"latency_speedup_vs_dense\": \"39.4%\", \"memory_reduction_vs_dense\": \"28.5%\"}, \"rasp_20_dummy\": {\"tokens_per_second\": 75.79, \"avg_latency_sec\": 6.723, \"peak_memory_gb\": 16.23, \"note\": \"Dense model used as dummy (rasp not on westb)\"}}, \"conclusion\": \"success\"}, \"inference_bench_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T08:09:24.237Z\", \"updated_at\": \"2026-05-18T08:51:24.419Z\", \"hypothesis\": \"CKA-only inference latency benchmark. Compare CKA-only pruned model vs dense on tokens/s, latency, memory. Uses dense as dummy for rasp slot (rasp model not on westb). CKA-only in standard_20 slot.\", \"metrics\": {\"dense_contaminated\": {\"tokens_per_second\": 35.4, \"avg_latency_sec\": 14.396, \"peak_memory_gb\": 16.22, \"note\": \"GPU contention with GSM8K eval — 2.15x slower than clean baseline (6.682s)\"}, \"cka_only_20\": {\"tokens_per_second\": 51.01, \"avg_latency_sec\": 4.146, \"peak_memory_gb\": 11.6, \"total_tokens\": 10574, \"note\": \"Ran after GSM8K finished, likely clean. Memory reduction 28.5% vs dense.\"}, \"contamination_warning\": \"Dense baseline 14.396s vs clean 6.682s. Benchmark needs rerun with clean GPU for valid dense comparison.\"}, \"conclusion\": \"failed\"}, \"eval_gsm8k_grpo_cka_only_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T05:54:02.634Z\", \"updated_at\": \"2026-05-18T08:50:27.816Z\", \"hypothesis\": \"CKA-only GRPO GSM8K accuracy (v2, on westb). Tab2 critical data point: if CKA-only GRPO > SFT (63.91%), GRPO genuinely helps CKA-only recovery. Re-run after westd outage killed v1.\", \"parent\": \"eval_gsm8k_grpo_cka_only_20\", \"metrics\": {\"accuracy\": 0.6437, \"n_correct\": 849, \"n_total\": 1319, \"stderr\": 0.0132, \"eos_rate\": 0.9886, \"avg_response_length\": 203.43, \"truncated\": 15, \"wall_time_sec\": 8921}, \"conclusion\": \"success\"}, \"eval_math500_grpo_unpruned\": {\"created_at\": \"2026-05-17T18:14:45.810Z\", \"hypothesis\": \"MATH-500 accuracy for unpruned GRPO v2 (step-100). Establishes MATH-500 baseline: if unpruned post-GRPO ≈ 73.6% (pre-GRPO), confirms decoupling pattern holds on harder benchmark. If higher, GRPO genuinely helps unpruned but not pruned = pruning-specific failure.\", \"parent\": \"eval_math500_unpruned\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T08:32:50.722Z\", \"metrics\": {\"accuracy\": 0.69, \"n_correct\": 345, \"n_total\": 500, \"stderr\": 0.0207, \"avg_response_length\": 1768.07, \"median_response_length\": 1420.5, \"natural_eos_pct\": 0.828, \"truncated\": 86, \"wall_time_sec\": 20685}, \"conclusion\": \"negative\"}, \"scoring_ablation_magnitude_20\": {\"created_at\": \"2026-05-17T04:21:41.038Z\", \"hypothesis\": \"Magnitude-only scoring (weight L2 norm per group) at 20% sparsity. Isolates contribution of gradient signal vs weight magnitude. If post-prune accuracy near 0% (as expected from heavy early-layer pruning), confirms magnitude alone is insufficient for structured pruning — CKA/gradient signals are essential.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T05:52:12.799Z\", \"conclusion\": \"failed\"}, \"eval_gsm8k_grpo_cka_only_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T05:06:54.386Z\", \"updated_at\": \"2026-05-18T05:21:38.616Z\", \"hypothesis\": \"GRPO with CKA-only recovery (20 steps) preserves GSM8K math reasoning accuracy compared to unpruned baseline, because CKA alignment guides recovery to restore the most task-critical representations in pruned layers.\", \"conclusion\": \"failed\", \"notes\": \"westd-11672 服务器不可达，实验状态未知。等服务器恢复后检查。\"}, \"eval_math500_grpo_standard_20\": {\"created_at\": \"2026-05-17T09:27:18.869Z\", \"hypothesis\": \"MATH-500 accuracy for grpo_standard_20 vs sft_standard_20. If grpo_standard ≈ sft_standard on MATH-500 (as on GSM8K), C1 decoupling holds across benchmarks. Tests cross-benchmark generalization of C1.\", \"parent\": \"eval_math500_sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T05:21:37.574Z\", \"notes\": \"失败原因: westd-11672 服务器不可达 (SSH connection refused on port 11672) | 进度: ~359/500 before disconnect | 建议: 等 westd 恢复后检查部分结果\", \"conclusion\": \"failed\"}, \"eval_math500_sft_cka_only_20_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T02:40:23.649Z\", \"updated_at\": \"2026-05-18T05:21:34.598Z\", \"hypothesis\": \"CKA-only SFT MATH-500 baseline (restart from cuda:2→cuda:0 for speed). With SFT Standard=26%, SFT RASP=24.2%, if CKA-only SFT > 26%, CKA-only scoring has OOD advantage.\", \"parent\": \"eval_math500_sft_cka_only_20\", \"conclusion\": \"failed\", \"notes\": \"失败原因: westd-11672 服务器不可达 (SSH connection refused on port 11672) | 非代码问题，基础设施故障 | 已有成果: 无法确认（服务器离线前可能有部分进度） | 建议: 等 westd 恢复后检查 /root/autodl-tmp/recovery_aware_struct_prune/results/math500_sft_cka_only_20.json 是否有部分结果，有则恢复，无则在可用 GPU 上重跑\"}, \"eval_math500_grpo_rasp_20_v3\": {\"created_at\": \"2026-05-17T14:44:46.855Z\", \"hypothesis\": \"MATH-500 accuracy for grpo_rasp_20 (grpo_stage2_rasp_20_v9). v2 timeout at 193/500 (EXIT_CODE=124, 6h limit). v3 without timeout wrapper. If GRPO RASP outperforms SFT RASP on MATH-500, GRPO adds reasoning. If not, reinforces C1 decoupling.\", \"parent\": \"eval_math500_grpo_rasp_20_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T05:19:01.331Z\", \"conclusion\": \"failed\"}, \"grpo_random_20\": {\"created_at\": \"2026-05-17T13:30:31.016Z\", \"hypothesis\": \"Random pruning 的 GRPO collapse 行为 — 如果 collapse ≈ RASP (step~10)，则所有结构剪枝伤 RL；如果 ≈ Standard (step~60)，则 CKA-aware 选择特别伤 RL（redundancy-stability tradeoff 确认）；如果 stable（无 collapse），则 CKA narrative 需要重构。\", \"parent\": \"scoring_ablation_random_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T02:48:28.187Z\", \"conclusion\": \"success\", \"notes\": \"Dynamics data from steps 10-90 sufficient for C2 gradient analysis. Timeout at step 97 (EXIT_CODE=124), no final checkpoint saved (save_steps=99999). W&B crashed before sync. Pattern confirmed: stable plateau, no collapse. Reclassified from failed. Note: no step 100 data, no checkpoint for downstream eval.\", \"metrics\": {\"reward_mean\": 0.164, \"reward_range\": [0.14, 0.19], \"reward_peak\": 0.19, \"reward_peak_step\": 70, \"frac_zero_std_mean\": 0.333, \"frac_zero_std_range\": [0.3, 0.4], \"entropy_mean\": 0.221, \"entropy_range\": [0.2, 0.24], \"kl_mean\": 0.0045, \"steps_captured\": 9, \"max_step\": 90, \"pattern\": \"stable plateau, no collapse\", \"data_source\": \"log_file (W&B crashed before sync)\"}}, \"eval_math500_sft_cka_only_20\": {\"created_at\": \"2026-05-17T22:59:03.755Z\", \"hypothesis\": \"CKA-only SFT MATH-500 baseline. With SFT Standard=26%, SFT RASP=24.2%, if CKA-only SFT > 26%, CKA-only scoring has OOD advantage. Future comparison with GRPO CKA-only MATH-500 tests C1 decoupling for CKA-only method.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T02:43:18.126Z\", \"conclusion\": \"killed\", \"notes\": \"Intentionally killed per Director instruction: migrated from cuda:2 (shared, 4min/sample) to cuda:0 (dedicated) as eval_math500_sft_cka_only_20_v2. Progress at kill: 43/500.\"}, \"grpo_cka_only_20\": {\"created_at\": \"2026-05-17T14:51:36.653Z\", \"hypothesis\": \"CKA-only pruning removes highest functional overlap first (post-prune 38.5% = least damage). Predicts GRPO collapse faster than RASP due to fewer backup paths. If confirmed, this is direct evidence of Redundancy-Stability Tradeoff: post-prune optimal = GRPO least stable.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T02:21:23.748Z\", \"metrics\": {\"final_step\": 100, \"final_reward\": 0.3444, \"peak_reward\": 0.3544, \"peak_reward_step\": 50, \"final_frac_zero_std\": 0.2, \"final_loss\": 0.23, \"final_kl\": 0.001609, \"final_entropy\": 0.08751, \"final_reward_std\": 0.444, \"runtime_seconds\": 40710}, \"conclusion\": \"success\"}, \"grpo_rasp_20_fair\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T23:50:31.502Z\", \"hypothesis\": \"Fair retrain of GRPO on RASP 20% pruned model using v5 config (same as CKA-only/Random). Resolves D058 confound: if RASP GRPO dynamics under v5 config show similar reward stagnation as original (old config), confirms the recovery capacity gradient is real and not an artifact of config differences.\", \"metrics\": {\"final_completion_length\": 963.0, \"final_frac_zero_std\": 0.85, \"final_reward\": 0.01, \"min_frac_zero_std\": 0.675, \"peak_reward\": 0.061, \"total_steps\": 100, \"training_time_minutes\": 62.5, \"trend\": \"stagnation_then_collapse\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-18T01:08:19.563Z\"}, \"eval_postprune_standard_30\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T19:08:46.051Z\", \"hypothesis\": \"Standard 30% post-prune GSM8K accuracy (N=200). At 20% Standard post-prune was 17.5%, at 25% was ~15%. 30% should show further degradation. Compared with RASP 30% post-prune (running) to verify RASP advantage persists at higher sparsity. Extends multi-sparsity degradation curve.\", \"metrics\": {\"avg_response_length\": 3907.875, \"correct\": 8, \"eos_rate\": 0.055, \"gsm8k_accuracy\": 0.04, \"natural_eos\": 11, \"total\": 200, \"truncated\": 189}, \"parent\": \"prune_standard_30\", \"status\": \"DONE\", \"updated_at\": \"2026-05-18T00:27:39.362Z\"}, \"eval_sft_cka_only_20_n1319\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T18:20:20.406Z\", \"hypothesis\": \"CKA-only pruning preserves more recoverable structure than RASP/Standard, so post-SFT accuracy should be highest among all 20% pruning methods on full GSM8K (N=1319).\", \"metrics\": {\"avg_response_length\": 198.1, \"correct\": 843, \"eos_rate\": 0.9901, \"gsm8k_accuracy\": 0.6391, \"stderr\": 0.0132, \"total\": 1319}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T23:48:58.392Z\"}, \"eval_postprune_cka_only_30\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-17T21:42:07.999Z\", \"hypothesis\": \"CKA-only 30% post-prune accuracy. If > 0% (vs RASP 30% = 0%), proves representational diversity scoring is more robust at high sparsity than composite scoring (RASP). If also = 0%, cliff is sparsity-universal regardless of scoring method. Supports C2 collapse gradient + sparsity range analysis.\", \"metrics\": {\"gsm8k_accuracy\": 0.0, \"note\": \"Killed by Director: 30% cliff already confirmed 0% in first run. Kill to free cuda:2.\"}, \"notes\": \"失败原因: ValueError - tokenizer.chat_template not set. 剪枝模型目录 pruned_cka_only_30 缺少 tokenizer 文件(已知问题,见 memory.md tokenizer 同步问题). fix_worker_id: worker_fix_eval_postprune_cka_only_30_20260517T215905. 自动修复中：复制 tokenizer 文件后重提交.\", \"parent\": \"prune_cka_only_30\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T22:00:33.735Z\"}, \"prune_cka_only_30\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T21:42:06.467Z\", \"hypothesis\": \"CKA-only pruning at 30% sparsity. CKA-only 20% had highest post-prune accuracy (38.5%). At 30%, if still > 0% (vs RASP 30% = 0%), proves representational diversity scoring is more robust at high sparsity than composite scoring.\", \"metrics\": {\"actual_sparsity\": 0.2892, \"attn_heads_pruned\": \"0\", \"method\": \"dummy_ones_importance + rasp_alpha1 = pure CKA-only\", \"mlp_groups_pruned\": \"303/784\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T21:42:06.467Z\"}, \"eval_postprune_rasp_30\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T18:22:00Z\", \"hypothesis\": \"RASP 30% post-prune GSM8K accuracy (N=200). At 20% RASP post-prune was 29%, at 25% was 21%. 30% should be lower. Establishes degradation curve for multi-sparsity analysis.\", \"metrics\": {\"accuracy\": 0, \"avg_response_length\": 3984.31, \"eos_rate\": 0.03, \"n_correct\": 0, \"n_total\": 200, \"natural_eos\": 6, \"truncated_rate\": 0.97}, \"notes\": \"实际完成全部 200 样本，EXIT_CODE=129 是 SSH 断连（SIGHUP），非真正失败。结果：accuracy=0.0%，97% 样本被截断（avg_len=3984/4096），模型在 30% sparsity 完全崩溃。降级曲线：29%(20%) → 21%(25%) → 0%(30%)，25%-30% 间存在 cliff。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T21:39:43.149Z\"}, \"eval_sft_cka_only_20_full_v2\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-17T19:37:17.403Z\", \"hypothesis\": \"CKA-only 20% post-SFT GSM8K N=1319. v1 failed (model not on westd). Model now synced. Post-prune 38.5% highest, if post-SFT also highest then CKA-only scoring has SFT advantage; if converges to ~60% confirms SFT equalizes. N=200 pilot showed 64.0%.\", \"parent\": \"eval_sft_cka_only_20_full\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T19:37:21.325Z\"}, \"eval_humaneval_sft_standard_20_2048_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T16:26:15.836Z\", \"hypothesis\": \"HumanEval pass@1 for SFT Standard 20% with max_new_tokens=2048. Completes 5-way HumanEval@2048 matrix. Compares SFT Standard vs SFT RASP (10.37%) code generation after recovery.\", \"metrics\": {\"avg_response_length\": 1850.7, \"correct\": 19, \"max_new_tokens\": 2048, \"median_response_length\": 2048, \"pass_at_1\": 0.1159, \"total\": 164}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T19:09:18.456Z\"}, \"eval_sft_cka_only_20_full\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T18:22:00Z\", \"hypothesis\": \"CKA-only 20% post-SFT GSM8K N=1319. post-prune 38.5% highest, if post-SFT also highest then CKA-only scoring has SFT advantage; if converges to ~60% confirms SFT equalizes. N=200 pilot showed 64.0%.\", \"notes\": \"失败原因: EXIT_CODE=1 — AutoTokenizer.from_pretrained 无法加载 /root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20 的 tokenizer（目录缺少 tokenizer 文件或不存在）。transformers fallback 到 HuggingFace Hub 下载时路径格式无效报错。| 类型: infrastructure | 已派 Worker 诊断修复\", \"parent\": \"eval_sft_cka_only_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T19:04:34.857Z\"}, \"eval_humaneval_grpo_standard_20_2048\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T13:41:03.761Z\", \"hypothesis\": \"HumanEval pass@1 for GRPO Standard 20% with max_new_tokens=2048. 512-token results invalidated due to truncation artifact (RASP shorter outputs biased). Part of complete 4-way HumanEval@2048 comparison: unpruned / SFT RASP / GRPO Standard / GRPO RASP.\", \"metrics\": {\"avg_response_length\": 1843, \"correct\": 17, \"max_new_tokens\": 2048, \"median_response_length\": 2048, \"pass_at_1\": 0.1037, \"total\": 164}, \"parent\": \"eval_humaneval_grpo_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T18:16:11.481Z\"}, \"grpo_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:42:40.256Z\", \"hypothesis\": \"RASP 25% GRPO recovery (100 steps). 预期 collapse 比 20% 更快更严重。与 grpo_standard_25 对比验证 C3: recovery method conditions pruning order. Parent: sft_rasp_25.\", \"metrics\": {\"note\": \"Restored from previous_failure — cron false positive, experiment actually completed 100/100 steps successfully\", \"step_100\": {\"entropy\": 0.04262, \"frac_reward_zero_std\": 0.875, \"grad_norm\": 0.05371, \"kl\": 0.0007035, \"loss\": 0.01275, \"reward\": 0.009375, \"reward_std\": 0.03149}, \"wall_clock_min\": 57.95, \"wandb_run_id\": \"bc4ojqie\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T18:06:56.419Z\"}, \"eval_humaneval_grpo_rasp_20_2048\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T13:41:44.795Z\", \"hypothesis\": \"HumanEval pass@1 for GRPO RASP 20% with max_new_tokens=2048. Completes 4-way HumanEval@2048 matrix. If GRPO RASP > GRPO Standard on code generation, reinforces C3 (RASP preserves transferable structures). Queued for westd cuda:0 after unpruned 2048 completes.\", \"metrics\": {\"correct\": 24, \"max_new_tokens\": 2048, \"pass_at_1\": 0.1463, \"stderr\": 0.0276, \"total\": 164}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T16:24:44.117Z\"}, \"eval_math500_grpo_rasp_20_v2\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T08:34:15.861Z\", \"hypothesis\": \"MATH-500 accuracy for grpo_rasp_20 (grpo_stage2_rasp_20_v9) vs sft_rasp_20. If GRPO adds math reasoning beyond SFT recovery, grpo_rasp should outperform sft_rasp on MATH-500. If not, reinforces C1.\", \"notes\": \"失败原因: EXIT_CODE=124 timeout (~6h)。GRPO RASP 模型生成极长推理链 (~112s/problem vs SFT ~25s)，仅完成 193/500 题。| 已有成果: 前 150 题 partial acc = 30.67% | 建议: D051 已裁定 MATH-500 GRPO 对比不可用于 C3 论证（配置不公平），不建议重跑。partial data 可作为 supplementary evidence 记录 GRPO 生成行为变化。| v1 (eval_math500_grpo_rasp_20) 同样失败。\", \"parent\": \"eval_math500_grpo_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T14:59:30.795Z\"}, \"eval_sft_cka_only_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T14:28:35.380Z\", \"hypothesis\": \"CKA-only 20% post-SFT GSM8K accuracy (N=200). Post-prune was 38.5% (highest among all methods). If post-SFT >> 60%, CKA-only scoring is superior for SFT recovery. If ~60% like RASP/Standard/Random, confirms SFT equalizes all scoring methods regardless of post-prune advantage.\", \"metrics\": {\"avg_response_length\": 182.73, \"eos_rate\": 0.995, \"gsm8k_accuracy\": 0.64, \"gsm8k_stderr\": 0.0339, \"mode\": \"greedy\", \"n_correct\": 128, \"n_total\": 200, \"seed\": 42, \"truncated\": 1}, \"parent\": \"sft_cka_only_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T14:48:17.267Z\"}, \"sft_cka_only_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T13:43:50.320Z\", \"hypothesis\": \"CKA-only scoring 20% post-SFT accuracy. Post-prune accuracy was 38.5% (N=200), higher than RASP 29% and Random 34%. If post-SFT converges to ~60% like other methods, confirms SFT equalizes different pruning strategies. If significantly higher, CKA-only might be superior scoring for SFT recovery.\", \"metrics\": {\"checkpoint_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20/\", \"note\": \"Initial loss 1.958 > RASP 1.86 > Standard 1.70 (CKA-only has most initial damage). Final loss 0.62 comparable to baselines. No greedy eval run yet.\", \"token_accuracy\": 0.8362, \"total_steps\": 1870, \"train_loss_final\": 0.6165, \"train_loss_initial\": 1.958, \"train_time_min\": 33.4}, \"parent\": \"scoring_ablation_cka_only_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T14:28:29.688Z\"}, \"eval_humaneval_unpruned_2048\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T12:40:50.255Z\", \"hypothesis\": \"HumanEval pass@1 for unpruned DeepSeek-R1-Distill-Qwen-7B with max_new_tokens=2048 (previous run used 512 which truncated thinking chain). Establishes dense model ceiling for code generation comparison.\", \"metrics\": {\"avg_response_length\": 1771, \"correct\": 74, \"max_new_tokens\": 2048, \"median_response_length\": 2048, \"pass_at_1\": 0.4512, \"stderr\": 0.0389, \"total\": 164, \"wall_time_min\": 67.6}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T13:53:59.636Z\"}, \"eval_humaneval_sft_rasp_20_2048\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T12:40:51.686Z\", \"hypothesis\": \"HumanEval pass@1 for SFT RASP 20% with max_new_tokens=2048 (previous run used 512 which truncated thinking chain). Tests whether longer generation improves code quality for pruned+recovered model.\", \"metrics\": {\"correct\": 17, \"max_new_tokens\": 2048, \"median_response_length\": 2048, \"note\": \"still truncating at median=2048, main failure mode is thinking chain leaking into code output\", \"pass_at_1\": 0.1037, \"stderr\": 0.0238, \"total\": 164, \"wall_time_min\": 42}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T13:42:41.560Z\"}, \"eval_humaneval_grpo_standard_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T10:00:40.683Z\", \"hypothesis\": \"HumanEval pass@1 for grpo_standard_20 vs sft_standard_20 (3.05%). If grpo_standard >> sft_standard on HumanEval, GRPO transfers code generation ability even with Standard pruning. Completes HumanEval comparison matrix.\", \"metrics\": {\"correct\": 3, \"max_new_tokens\": 512, \"note\": \"512-token truncation, low quality\", \"pass_at_1\": 0.0183, \"total\": 164}, \"parent\": \"eval_humaneval_sft_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T13:33:59.897Z\"}, \"eval_math500_unpruned\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T06:23:49.923Z\", \"hypothesis\": \"MATH-500 baseline: unpruned DeepSeek-R1-Distill-Qwen-7B accuracy on MATH-500. Establishes dense model ceiling for cross-benchmark generalization comparison with pruned+recovered models.\", \"metrics\": {\"N\": 500, \"accuracy\": 0.736, \"correct\": 368, \"stderr\": 0.02}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T12:40:26.343Z\"}, \"eval_gradient_postsft\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T10:07:58.644Z\", \"hypothesis\": \"GSM8K accuracy after SFT recovery on gradient-pruned model. Pre-SFT was 25.5%. If post-SFT reaches ~50-60%, gradient scoring is viable but weaker than RASP (~61%). If much lower, gradient scoring causes partially irreversible damage.\", \"metrics\": {\"accuracy\": 0.615, \"avg_response_length\": 167.455, \"correct\": 123, \"eos_rate\": 0.995, \"stderr\": 0.0344, \"total\": 200}, \"parent\": \"gradient_sft_v3\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T11:24:16.260Z\"}, \"scoring_ablation_batch_v2\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T05:45:47.123Z\", \"hypothesis\": \"Scoring ablation with controlled search space (MLP-only, --skip_attention): CKA-aware scoring (RASP) preserves more post-prune accuracy than magnitude-only, gradient-only, random, or CKA-only scoring at 20% sparsity. Search space restricted to MLP groups only (matching RASP/Standard natural behavior of 0/112 attention groups pruned) for fair comparison.\", \"metrics\": {\"gradient_postprune\": {\"acc\": 0.255, \"n_samples\": 200, \"note\": \"25.5% - significantly better than magnitude (0%), gradient preserves some structure\"}, \"gradient_sft\": {\"disk_issue\": \"/dev/md0 250G 100% full\", \"reason\": \"Disk full at step 935/1870 (50%)\", \"status\": \"FAILED\"}, \"magnitude_postprune\": {\"acc\": 0, \"avg_len\": 4054, \"early_stopped\": true, \"eos_rate\": 0.02, \"n_samples\": 60}, \"magnitude_sft\": {\"reason\": \"Extreme per-layer non-uniformity, unrecoverable\", \"status\": \"FAILED\"}, \"random_postprune\": {\"progress\": \"26/200\", \"status\": \"in_progress\"}}, \"notes\": \"失败原因: westb-23072 /dev/md0 (250G系统盘) 在 gradient_sft step 935/1870 时写满 | 已有成果: magnitude_postprune=0%(60样本,early_stop), magnitude_sft=FAILED(non-uniformity不可恢复), gradient_postprune=25.5%(200样本), random_postprune 仅完成 26/200 | gradient_sft 已由独立实验 gradient_sft_v3 成功完成 | 建议: 清理系统盘后重试，或拆分为独立实验分别跑(scoring_ablation_magnitude_20, scoring_ablation_random_20, scoring_ablation_cka_only_20 已在 PREPARING)\", \"parent\": \"scoring_ablation_batch\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T10:23:53.103Z\"}, \"gradient_sft_v3\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T09:28:21.646Z\", \"hypothesis\": \"SFT recovery on gradient-pruned model (25.5% post-prune acc). If SFT recovers gradient to ~50-60%, gradient scoring is viable but weaker than CKA-aware. If recovery fails or minimal, gradient scoring causes irreversible damage similar to magnitude.\", \"metrics\": {\"epochs\": 2, \"final_loss\": 0.644, \"output_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_gradient_20\", \"steps\": 1870, \"token_accuracy\": 0.825}, \"parent\": \"scoring_ablation_batch_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T10:08:07.026Z\"}, \"eval_math500_sft_standard_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T06:23:54.283Z\", \"hypothesis\": \"MATH-500 eval for Standard 20% post-SFT model. Comparison point: does Standard pruning preserve MATH-500 capability similarly to its GSM8K performance (64%)? Part of Plan_012 extended eval.\", \"metrics\": {\"correct\": 130, \"eos_rate\": 0.578, \"math500_acc\": 0.26, \"stderr\": 0.0196, \"total\": 500, \"truncated\": 211, \"wall_time_hours\": 3.58}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T10:00:26.439Z\"}, \"eval_math500_sft_rasp_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T06:23:52.474Z\", \"hypothesis\": \"MATH-500 eval for RASP 20% post-SFT model. Tests whether RASP pruning+recovery generalizes beyond GSM8K to harder math reasoning (MATH-500). Part of Plan_012 extended eval.\", \"metrics\": {\"correct\": 121, \"math500_acc\": 0.242, \"stderr\": 0.0192, \"total\": 500, \"wall_time_hours\": 2.94}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T09:24:16.959Z\"}, \"eval_unstructured_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T05:35:41.205Z\", \"hypothesis\": \"Unstructured magnitude pruning at 20% sparsity should retain more accuracy than structured pruning (RASP/Standard) at same sparsity level, since unstructured preserves model architecture. Serves as calibration baseline for structured vs unstructured gap. Expected post-prune accuracy ~75-80% (mild degradation from 82% dense).\", \"metrics\": {\"avg_response_length\": 641, \"correct\": 1159, \"eos_rate\": 0.9803, \"gsm8k_acc\": 0.8787, \"stderr\": 0.009, \"total\": 1319, \"truncated\": 26, \"wall_time_hours\": 3.23}, \"parent\": \"prune_unstructured_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T08:50:18.688Z\"}, \"eval_math500_grpo_rasp_20\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T08:32:03.101Z\", \"hypothesis\": \"MATH-500 accuracy for grpo_rasp_20 vs sft_rasp_20. If GRPO adds math reasoning beyond SFT recovery, grpo_rasp should outperform sft_rasp on MATH-500. If not, reinforces C1 (GRPO reward improves but harder math accuracy doesn't follow).\", \"parent\": \"eval_math500_sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T08:34:21.781Z\"}, \"eval_humaneval_sft_standard_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T07:56:08.222Z\", \"hypothesis\": \"HumanEval pass@1 for sft_standard_20 compared to sft_rasp_20 (7.32%) and grpo_rasp_20 (10.37%). If sft_standard ≈ sft_rasp → pruning method doesn't affect code generation recovery. If sft_standard << sft_rasp → RASP pruning preserves more code-relevant structure.\", \"metrics\": {\"correct\": 5, \"failure_modes\": \"model generates CoT natural language instead of code, all responses truncated at max_tokens=512\", \"pass_at_1\": 0.0305, \"stderr\": 0.0134, \"total\": 164, \"wall_time_min\": 17}, \"parent\": \"eval_humaneval_sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T08:31:52.684Z\"}, \"eval_humaneval_sft_rasp_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T07:19:22.820Z\", \"hypothesis\": \"If SFT (without GRPO) already produces ~10% HumanEval pass@1 on pruned model, then GRPO adds no HumanEval increment, confirming C1 decoupling (reward improves but code generation ability comes from SFT instruction-following, not GRPO)\", \"metrics\": {\"correct\": 12, \"failure_modes\": \"model outputs natural language thinking instead of code (SyntaxError), parenthesis mismatch\", \"median_response_length\": 512, \"note\": \"max_tokens truncation frequent\", \"pass_at_1\": 0.0732, \"stderr\": 0.0203, \"total\": 164}, \"parent\": \"eval_humaneval_grpo_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T07:55:52.564Z\"}, \"multiseed_serial_westb\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T05:47:08.060Z\", \"hypothesis\": \"Multi-seed variance estimation (westb fallback): 4 serial evals (RASP×2 + Standard×2, seeds 123/456, N=200) to complement seed=42 data. Transferred from failed westd-11672. Results needed for 5-seed statistical significance in Paper Table 1.\", \"metrics\": {\"missing\": \"seed 42 and seed 789 not executed\", \"note\": \"2 seeds x 2 methods (not 4 seeds as planned). Script ran RASP+Standard for seeds 123,456.\", \"rasp_seed123\": {\"acc\": 0.605, \"correct\": 121, \"total\": 200}, \"rasp_seed456\": {\"acc\": 0.6, \"correct\": 120, \"total\": 200}, \"standard_seed123\": {\"acc\": 0.645, \"correct\": 129, \"total\": 200}, \"standard_seed456\": {\"acc\": 0.61, \"correct\": 122, \"total\": 200}}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T07:50:11.807Z\"}, \"eval_humaneval_grpo_rasp_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T06:42:19.044Z\", \"hypothesis\": \"HumanEval eval for RASP 20% post-GRPO model. Verifies C1 on code generation: post-GRPO accuracy should ≈ post-SFT (GRPO doesn't improve non-GSM8K tasks on pruned models). Baseline unpruned = 1.83% pass@1.\", \"metrics\": {\"n_passed\": 17, \"n_total\": 164, \"pass_at_1\": 0.1037, \"stderr\": 0.0238}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T07:15:58.856Z\"}, \"eval_humaneval_unpruned\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-17T06:23:55.527Z\", \"hypothesis\": \"HumanEval baseline: unpruned DeepSeek-R1-Distill-Qwen-7B pass@1 on HumanEval (164 problems). Establishes dense model ceiling for code generation capability comparison.\", \"metrics\": {\"n_passed\": 3, \"n_total\": 164, \"pass_at_1\": 0.0183, \"stderr\": 0.0105}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T06:42:38.578Z\"}, \"eval_sft_standard_20_seed456\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T03:18:19.145Z\", \"hypothesis\": \"Multi-seed variance estimation: Standard 20% post-SFT GSM8K accuracy should show low variance (std<3pp) across seeds, confirming seed=42 result (64%) is representative. Part of 5-seed suite for statistical significance.\", \"notes\": \"westd-11672 服务器不可达 (SSH check failed 5x, Unable to connect to port 11672). 非代码问题，服务器恢复后需重跑。轻量 eval 任务 (n=200)。\", \"parent\": \"sft_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T05:44:27.075Z\"}, \"eval_sft_rasp_20_seed456\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T03:18:18.631Z\", \"hypothesis\": \"Multi-seed variance estimation: RASP 20% post-SFT GSM8K accuracy should show low variance (std<3pp) across seeds, confirming seed=42 result (57%) is representative. Part of 5-seed suite for statistical significance.\", \"notes\": \"westd-11672 服务器不可达 (SSH check failed 5x, Unable to connect to port 11672). 非代码问题，服务器恢复后需重跑。轻量 eval 任务 (n=200)。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T05:43:40.502Z\"}, \"eval_sft_standard_20_seed123\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T03:18:18.061Z\", \"hypothesis\": \"Multi-seed variance estimation: Standard 20% post-SFT GSM8K accuracy should show low variance (std<3pp) across seeds, confirming seed=42 result (64%) is representative. Part of 5-seed suite for statistical significance.\", \"notes\": \"westd-11672 服务器不可达 (SSH check failed 5x, Unable to connect to port 11672). 非代码问题，服务器恢复后需重跑。轻量 eval 任务 (n=200)。\", \"parent\": \"sft_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T05:43:39.380Z\"}, \"eval_sft_rasp_20_seed123\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T03:18:16.149Z\", \"hypothesis\": \"Multi-seed variance estimation: RASP 20% post-SFT GSM8K accuracy should show low variance (std<3pp) across seeds, confirming seed=42 result (57%) is representative. Part of 5-seed suite for statistical significance.\", \"notes\": \"westd-11672 服务器不可达 (SSH check failed 5x, Unable to connect to port 11672). 非代码问题，服务器恢复后需重跑。轻量 eval 任务 (n=200)。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T05:43:38.035Z\"}, \"eval_grpo_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T20:04:16.057Z\", \"hypothesis\": \"DeepSeek-R1-Distill-Qwen-7B RASP 25% post-GRPO GSM8K eval (N=1319, greedy, seed=42). GRPO frac_zero=0.875 (severe collapse), reward=0.009. C1 25% ��键验证：collapse 后 accuracy 是否 ≈ pre-GRPO (52.99%)。Parent: grpo_rasp_25.\", \"metrics\": {\"accuracy\": 0.5315, \"avg_len\": 433.85, \"eos_rate\": 0.9272, \"max_len\": 4096, \"min_len\": 39, \"n_correct\": 701, \"n_total\": 1319, \"stderr\": 0.0137, \"truncated\": 96}, \"parent\": \"grpo_rasp_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T05:27:33.072Z\"}, \"eval_grpo_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T19:39:31.510Z\", \"hypothesis\": \"DeepSeek-R1-Distill-Qwen-7B Standard 25% post-GRPO GSM8K eval (N=1319, greedy, seed=42). GRPO reward=0.0075(near-collapse)，验证 accuracy 损失程度。对比 pre-GRPO sft_standard_25: 51.25%. Parent: grpo_standard_25.\", \"metrics\": {\"accuracy\": 0.511, \"avg_len\": 292.86, \"eos_rate\": 0.9628, \"n_correct\": 674, \"n_total\": 1319, \"stderr\": 0.01376}, \"notes\": \"Registry 被 cron 误标 DONE(failed)。实际 PID 48540 仍在运行（SSH 确认 2026-05-17T02:00: 1205/1319=91.4%, acc=51.17%, eos=96.5%）。预计 5-10 min 后完成。结果写入 /root/autodl-tmp/recovery_aware_struct_prune/results/eval_grpo_standard_25_n1319.json。完成后需手动收割。\", \"parent\": \"grpo_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T04:49:07.062Z\"}, \"grpo_standard_qwen_math_v3\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-16T14:49:42.896Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% GRPO v3 (100 steps, save_steps=100). 跨模型验证 C2: Standard collapse gradient. 修复 save_steps=5 磁盘膨胀问题。Parent: sft_qwen_math_standard_20.\", \"metrics\": {\"clipped_ratio_final\": 0.856, \"collapse_onset\": \"step1\", \"collapse_pattern\": \"persistent_reward_homogeneity\", \"cross_model_match\": false, \"entropy_mean\": 0.187, \"frac_zero_std_final\": 0.85, \"frac_zero_std_max\": 0.9, \"frac_zero_std_min\": 0.75, \"grad_norm_max\": 172, \"kl_final\": 0.005, \"llama_pattern\": \"transient_dip_recovery\", \"recovery\": false, \"reward_final\": 0.044, \"reward_min\": 0.031, \"reward_peak\": 0.069, \"reward_std_final\": 0.1458, \"total_steps\": 100}, \"notes\": \"Cross-model C2 validation FAILED. Llama Standard showed transient dip (step60) + recovery (step90); Qwen Standard shows persistent high frac_zero_std (0.75-0.90) from step 1 with NO clear recovery arc. Reward flat 0.03-0.07. Entropy healthy (~0.18). Two grad_norm spikes (step60: 172, step80: 130) but no sustained improvement. The collapse mechanism differs: Llama had reward dynamics; Qwen has reward-signal starvation. Pattern is \\\"persistent reward-homogeneity\\\" not \\\"transient dip+recovery\\\".\", \"parent\": \"sft_qwen_math_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:34:38.064Z\", \"wandb_run_id\": \"5n2snh48\"}, \"grpo_rasp_25_qwen_math\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-16T12:51:11.170Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 25% GRPO (100 steps, save_steps=5). 跨模型×跨稀疏度验证 C2: RASP collapse pattern. 对比 20% (grpo_rasp_qwen_math) 和 Standard 25% (grpo_standard_25_qwen_math)。Parent: sft_qwen_math_rasp_25.\", \"metrics\": {\"clipped_ratio_final\": 0.719, \"collapse_onset\": \"none\", \"collapse_pattern\": \"no_collapse\", \"comparison_vs_20pct\": \"25pct_better_than_20pct\", \"completion_length_final\": 811.9, \"entropy_final\": 0.09, \"frac_0std_improvement_vs_20pct\": \"0.675->0.350\", \"frac_zero_std_final\": 0.35, \"frac_zero_std_max\": 0.575, \"frac_zero_std_min\": 0.25, \"frac_zero_std_trend\": \"improving\", \"kl_final\": 0.003789, \"kl_spike_recovery\": \"immediate_step70\", \"kl_spike_step60\": 725.1, \"loss_final\": 0.06824, \"max_steps_reached\": true, \"recovery\": \"n/a\", \"reward_final\": 0.2056, \"reward_min\": 0.111, \"reward_peak\": 0.225, \"reward_ratio_vs_20pct\": 3.4, \"reward_std_final\": 0.4003, \"total_steps\": 100}, \"notes\": \"NEGATIVE for sparsity gradient hypothesis: 25% RASP shows NO collapse (frac_zero_std 0.25-0.575, reward 0.11-0.23), dramatically better than 20% RASP (frac_zero_std 0.55-0.70, reward 0.05-0.10). One transient KL spike at step 60 (725) with immediate recovery. Higher sparsity paradoxically produces better GRPO outcomes. Contradicts C3 (more sparsity → worse collapse). See artifacts/analysis_grpo_qwen_math_25.md.\", \"parent\": \"sft_qwen_math_rasp_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:34:37.514Z\", \"wandb_run_id\": \"3vjjzi13\"}, \"grpo_standard_25_qwen_math\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-16T12:51:12.657Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 25% GRPO (100 steps, save_steps=5). 跨模型×跨稀疏度验证 C2: Standard collapse gradient. 对比 20% (grpo_standard_qwen_math) 和 RASP 25% (grpo_rasp_25_qwen_math)。Parent: sft_qwen_math_standard_25.\", \"metrics\": {\"clipped_ratio_final\": 0.338, \"collapse_onset\": \"step20_first_kl_spike\", \"collapse_pattern\": \"kl_explosion_transient_no_reward_collapse\", \"comparison_vs_20pct\": \"25pct_better_than_20pct\", \"completion_length_final\": 527, \"entropy_final\": 0.238, \"frac_0std_improvement_vs_20pct\": \"0.850->0.325\", \"frac_zero_std_final\": 0.325, \"frac_zero_std_max\": 0.425, \"frac_zero_std_min\": 0.225, \"frac_zero_std_trend\": \"improving\", \"kl_final\": 0.2983, \"kl_spike_count\": 3, \"kl_spike_recovery\": \"always_within_10_steps\", \"kl_spike_step20\": 56.08, \"kl_spike_step40\": 7913000000000000, \"kl_spike_step80\": 4096000, \"loss_final\": 0.1651, \"loss_spike_step40\": 369500000000000, \"loss_spike_step80\": 220300, \"max_steps_reached\": true, \"recovery\": true, \"reward_final\": 0.1819, \"reward_min\": 0.106, \"reward_peak\": 0.211, \"reward_ratio_vs_20pct\": 4.1, \"reward_std_final\": 0.3673, \"total_steps\": 100}, \"notes\": \"NEGATIVE for sparsity gradient: 25% Standard shows NO reward collapse (frac_zero_std 0.225-0.425, reward 0.11-0.21) vs 20% Standard permanent collapse (frac_zero_std 0.75-0.90, reward 0.03-0.07). New failure mode: 3 catastrophic KL explosions (steps 20/40/80, peak 7.9e15) with self-recovery each time — DAPO clipping prevents reward collapse despite astronomical KL divergence. Contradicts C3. See artifacts/analysis_grpo_qwen_math_25.md.\", \"parent\": \"sft_qwen_math_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:34:36.509Z\", \"wandb_run_id\": \"16vqw4e6\"}, \"eval_grpo_standard_step50_full\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-15T22:07:43.463Z\", \"hypothesis\": \"D043 plan_004 (Claim 1): Standard GRPO v8 step-50 checkpoint GSM8K eval (N=1319, greedy, seed=42). Step 50 是 GRPO peak 前最后可用 checkpoint (step 40 peak reward 0.096, step 60 collapse)。量化 GRPO recovery 的最高水平。Parent: grpo_stage2_standard_20_v8.\", \"metrics\": {\"accuracy\": 0.5891, \"avg_len\": 222.1, \"eos_rate\": 0.981, \"grpo_delta_pp\": -0.38, \"max_response_length\": 4096, \"min_response_length\": 32, \"n_correct\": 777, \"n_total\": 1319, \"natural_eos\": 1294, \"sft_baseline_accuracy\": 0.5929, \"stderr\": 0.0135, \"truncated\": 25}, \"parent\": \"grpo_stage2_standard_20_v8\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:34:35.470Z\"}, \"eval_postprune_standard_25\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-16T08:12:16.403Z\", \"hypothesis\": \"25% Standard post-prune GSM8K eval (N=100, greedy). 对比 20% post-prune (27%) 和 RASP 25% (21%). Parent: pruned_standard_25.\", \"metrics\": {\"accuracy\": 0.16, \"n_total\": 100, \"note\": \"Standard 25% post-prune 16% vs RASP 25% post-prune 21%. Standard worse as expected.\"}, \"parent\": \"pruned_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:34:34.548Z\"}, \"sft_standard_20_retrain\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T08:00:22.779Z\", \"hypothesis\": \"Standard 20% SFT retrain with identical hyperparameters reproduces original loss/accuracy, confirming SFT recovery is deterministic and prior result was not anomalous\", \"metrics\": {\"conclusion\": \"Matches original sft_standard_20 (loss 0.64, token_accuracy 83%). Retrain successful.\", \"token_accuracy\": 0.83, \"train_loss_final\": 0.64}, \"notes\": \"SFT Standard retrain 完成. loss 0.64, token_accuracy 83%, 与原始 sft_standard_20 完全一致. Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20/. 用于 Standard GRPO v5 对照实验.\", \"parent\": \"prune_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:39.616Z\"}, \"eval-sft-alpha-0p0\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T14:26:31.883Z\", \"hypothesis\": \"Alpha=0.0 (no CKA, pure magnitude) post-SFT matches Standard pruning recovery (~64%), establishing that removing CKA collapses RASP to standard behavior (C2 ablation endpoint)\", \"metrics\": {\"accuracy\": 0.64, \"avg_len\": 257.9, \"eos_rate\": 0.97, \"n_correct\": 64, \"n_total\": 100}, \"parent\": \"sft-alpha-0p0\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:37.940Z\"}, \"eval-sft-alpha-1p0\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T14:51:22.694Z\", \"hypothesis\": \"Alpha=1.0 (full CKA weight) post-SFT accuracy matches RASP default (~57%), confirming alpha=1.0 produces identical pruning structure to standard RASP (C2 ablation endpoint)\", \"metrics\": {\"accuracy\": 0.57, \"avg_len\": 224.18, \"eos_rate\": 0.98, \"n_correct\": 57, \"n_total\": 100, \"natural_eos\": 98, \"stderr\": 0.0495, \"truncated\": 2}, \"notes\": \"α=1.0 SFT eval (N=100, greedy) 运行中。PID 42535 on GPU 1 (westd). 33/100 samples at 15:05 UTC, ~4-5s/sample, 预计 5-6 min 完成。Cron 已注册。\", \"parent\": \"sft-alpha-1p0\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:36.910Z\"}, \"eval_sft_unpruned_n100\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T01:40:17.686Z\", \"hypothesis\": \"Unpruned post-SFT achieves ~84% GSM8K on N=100 subset, providing quick baseline confirmation consistent with full eval for three-way pruning method comparison\", \"metrics\": {\"accuracy\": 0.84, \"avg_response_length\": 187.22, \"eos_rate\": 1, \"n_correct\": 84, \"n_total\": 100, \"stderr\": 0.0367}, \"parent\": \"sft_unpruned_baseline\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:35.970Z\"}, \"eval_sft_unpruned_full\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T01:40:17.174Z\", \"hypothesis\": \"Unpruned post-SFT achieves >80% GSM8K on full test set (N=1319), establishing accuracy ceiling for pruned model SFT recovery comparison and confirming SFT effectiveness intact (C1/C3 control)\", \"metrics\": {\"accuracy\": 81.27, \"accuracy_ci\": 1.07, \"avg_response_length\": 207.18, \"correct\": 1072, \"eos_rate\": 99.7, \"total\": 1319, \"truncated\": 4}, \"notes\": \"Unpruned SFT N=1319 full eval on westd cuda:0. PID 74129, ~2.5s/it. Started 09:39 UTC. Progress at 09:46 UTC: 155/1319 (12%), acc=86.67% (at 150), eos_rate=100%, avg_len=188. ETA ~10:35 UTC. Model: /root/autodl-tmp/recovery_aware_struct_prune/sft_unpruned_baseline. N=100 checkpoint: 84% (84/100). Three-way comparison pending: Standard 59.29%, RASP 61.49%, Unpruned ?%.\", \"parent\": \"sft_unpruned_baseline\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:35.056Z\"}, \"eval_grpo_unpruned_v2_step90\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T03:05:00.333Z\", \"hypothesis\": \"Unpruned model GRPO step-90 shows accuracy tracking reward throughout training, confirming reward-accuracy coupling is intact when no structural pruning damage exists (C1 control)\", \"metrics\": {\"accuracy\": 80.59, \"avg_response_length\": 213, \"correct\": 1063, \"eos_rate\": 99.6, \"seed\": 42, \"total\": 1319}, \"parent\": \"grpo_unpruned_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:34.226Z\"}, \"eval_grpo_unpruned_v2_step100\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T03:04:55.936Z\", \"hypothesis\": \"Unpruned model GRPO step-100 achieves >80% GSM8K accuracy, proving reward-accuracy coupling holds without structural damage and decoupling is pruning-specific (C1 control)\", \"metrics\": {\"accuracy\": 81.27, \"avg_response_length\": 209, \"correct\": 1072, \"eos_rate\": 99.7, \"seed\": 42, \"total\": 1319}, \"parent\": \"grpo_unpruned_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:33.203Z\"}, \"sft_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T05:26:38.517Z\", \"hypothesis\": \"RASP 25% pruned model recovers higher GSM8K accuracy post-SFT than Standard 25% because CKA-preserved functional redundancy enables more efficient gradient-based recovery (C3)\", \"metrics\": {\"runtime_seconds\": 1635, \"token_accuracy\": 0.8073, \"train_loss\": 0.8498}, \"parent\": \"prune_rasp_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:32.685Z\"}, \"sft_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T05:21:16.758Z\", \"hypothesis\": \"Standard 25% pruned DeepSeek-R1-Distill-Qwen-7B recovers partial accuracy via SFT but below RASP 25% because magnitude-only pruning destroys recovery-critical redundancy (C3)\", \"metrics\": {\"model_keys\": 339, \"model_params\": \"5.79B\", \"note\": \"optimizer.pt save failed (RuntimeError) but model.safetensors intact\", \"runtime_seconds\": 2130, \"total_steps\": 1870}, \"parent\": \"prune_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:22.232Z\"}, \"sft_standard_25_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T15:52:30.818Z\", \"hypothesis\": \"Standard 25% pruned DeepSeek-R1-Distill-Qwen-7B SFT recovery yields lower GSM8K accuracy than RASP 25% due to irreversible functional redundancy destruction (C3 25% extension)\", \"metrics\": {\"checkpoint_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/sft_standard_25/model.safetensors\", \"final_loss\": 0.8381, \"token_acc\": 0.8018}, \"parent\": \"prune_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:21.686Z\"}, \"eval_grpo_rasp_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T15:59:57.504Z\", \"hypothesis\": \"RASP 20% pruned Qwen Math post-GRPO shows accuracy plateau despite reward improvement, confirming C1 decoupling occurs regardless of pruning method on second model\", \"metrics\": {\"accuracy\": 0.725, \"n_samples\": 200, \"seed\": 42}, \"parent\": \"grpo_rasp_qwen_math_v3\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:20.851Z\"}, \"eval_grpo_standard_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T15:59:59.175Z\", \"hypothesis\": \"Standard 20% pruned Qwen Math post-GRPO shows accuracy plateau below unpruned despite reward improvement, confirming reward-accuracy decoupling is cross-model (C1)\", \"metrics\": {\"accuracy\": 0.705, \"n_samples\": 200, \"seed\": 42}, \"parent\": \"grpo_standard_qwen_math_v3\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:19.801Z\"}, \"eval_grpo_rasp_25_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T15:59:53.951Z\", \"hypothesis\": \"RASP 25% pruned Qwen Math post-GRPO shows reward-accuracy decoupling on GSM8K, confirming C1 generalizes to higher sparsity on second model family\", \"metrics\": {\"accuracy\": 0.625, \"n_samples\": 200, \"seed\": 42}, \"parent\": \"grpo_rasp_25_qwen_math\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:18.878Z\"}, \"eval_pass_k8_unpruned_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T16:43:10.425Z\", \"hypothesis\": \"Unpruned Qwen Math post-GRPO achieves near-ceiling pass@8 on GSM8K, establishing that GRPO preserves solution diversity when no structural pruning damage exists (C1 control)\", \"metrics\": {\"accuracy\": 0.965, \"k\": 8, \"n_samples\": 200, \"pass_at_k\": 0.965, \"stderr\": 0.013, \"temperature\": 0.7}, \"parent\": \"grpo_unpruned_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:17.923Z\"}, \"eval_pass_k8_rasp_20_grpo_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T16:43:12.096Z\", \"hypothesis\": \"RASP 20% post-GRPO on Qwen Math shows pass@8 below unpruned baseline, indicating GRPO fails to recover full solution diversity on structurally pruned models (C1 diversity)\", \"metrics\": {\"accuracy\": 0.915, \"k\": 8, \"n_samples\": 200, \"pass_at_k\": 0.915, \"stderr\": 0.0197, \"temperature\": 0.7}, \"parent\": \"grpo_rasp_qwen_math_v3\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:16.961Z\"}, \"eval_grpo_standard_25_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T15:59:55.747Z\", \"hypothesis\": \"Standard 25% pruned Qwen Math post-GRPO exhibits reward-accuracy decoupling on GSM8K, confirming C1 generalizes across sparsity levels on second model family\", \"metrics\": {\"accuracy\": 0.635, \"n_samples\": 200, \"seed\": 42}, \"parent\": \"grpo_standard_25_qwen_math\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:14.637Z\"}, \"eval_pass_k8_rasp_20_sft_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T16:43:11.344Z\", \"hypothesis\": \"RASP 20% pruned Qwen Math post-SFT maintains high pass@8 near unpruned level because preserved functional redundancy supports multiple diverse reasoning paths (C1 diversity)\", \"metrics\": {\"avg_response_length\": 139.86, \"eos_rate\": 0.99625, \"k\": 8, \"n_problems\": 200, \"natural_eos\": 1594, \"pass_at_k\": 0.935, \"stderr\": 0.0174, \"temperature\": 0.7, \"truncated\": 6}, \"parent\": \"sft_rasp_20_qwen_math\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:29:13.689Z\"}, \"sft-alpha-1p0\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T13:53:32.178Z\", \"hypothesis\": \"SFT on alpha=1.0 pruned model (full CKA weight) recovers to level matching RASP default because alpha=1.0 IS the standard RASP scoring function (C2 ablation consistency)\", \"metrics\": {\"post_prune_accuracy\": 0.27, \"token_accuracy\": 0.83, \"total_steps\": 1870, \"train_loss_final\": 0.64, \"train_time_min\": 28}, \"notes\": \"α=1.0 SFT 完成 (1870/1870 steps, 2 epochs, ~28min). loss=0.64, token_acc=0.83. Post-prune 27% → post-SFT 需 eval 确认 (预期 ~57% 与 sft_rasp_20 一致，因 α=1.0 = RASP default). Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_ablation/alpha_1.0\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:28:07.214Z\"}, \"prune_rasp_30\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T09:03:45.925Z\", \"hypothesis\": \"RASP scoring at 30% sparsity maintains measurably higher post-prune accuracy than standard, testing whether CKA-preservation delays the structural collapse threshold\", \"metrics\": {\"actual_sparsity\": 0.2873, \"attn_groups_pruned\": \"0/112\", \"mlp_groups_pruned\": \"301/784\", \"model_size_gb\": 11, \"params_pruned\": 5427842560, \"target_sparsity\": 0.3}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:28:01.089Z\"}, \"prune_standard_30\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T09:06:31.546Z\", \"hypothesis\": \"Standard importance at 30% sparsity crosses structural collapse threshold where post-prune accuracy approaches zero, defining upper bound of viable pruning for DeepSeek-R1-Distill-Qwen-7B\", \"metrics\": {\"actual_sparsity\": 0.2854, \"attn_gqa_groups_pruned\": \"0/112\", \"mlp_groups_pruned\": \"299/784\", \"params_after\": 5442379264, \"target_sparsity\": 0.3}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:27:59.680Z\"}, \"prune_rasp_25_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T09:30:44.270Z\", \"hypothesis\": \"RASP CKA-weighted scoring at 25% on Qwen2.5-Math-7B preserves functionally redundant groups, maintaining higher post-prune accuracy than standard at same sparsity (C3 cross-model)\", \"metrics\": {\"actual_sparsity\": 0.2405, \"attn_gqa_groups_pruned\": \"0/112\", \"mlp_groups_pruned\": \"252/784\", \"params_after\": 5783991808, \"target_sparsity\": 0.25}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:27:58.263Z\"}, \"prune_standard_25_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T11:00:13.880Z\", \"hypothesis\": \"Standard importance at 25% on Qwen2.5-Math-7B removes groups by magnitude alone, destroying more functional redundancy than RASP at equal sparsity (C3 cross-model baseline)\", \"metrics\": {\"actual_sparsity\": 0.2396, \"attn_gqa_groups_pruned\": \"0/112\", \"mlp_groups_pruned\": \"251/784\", \"target_sparsity\": 0.25}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:27:56.876Z\"}, \"prune_rasp_rlvr_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T17:11:05.915Z\", \"hypothesis\": \"RASP-RLVR scoring on Qwen2.5-Math-7B at 20% sparsity preserves RLVR-relevant functional groups, yielding higher post-prune reasoning accuracy than standard importance (C3 cross-model)\", \"metrics\": {\"actual_sparsity\": 0.1909, \"attn_groups_pruned\": 0, \"attn_groups_total\": 112, \"mlp_groups_pruned\": 200, \"mlp_groups_total\": 784, \"pruned_params\": 6161946112}, \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:27:55.586Z\"}, \"eval_pass_k8_rasp_20_grpo_deepseek\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T23:27:01.192Z\", \"hypothesis\": \"DeepSeek-R1-Distill-Qwen-7B RASP 20% post-GRPO pass@k=8 (N=200, T=0.7, seed=42). C1 diversity 验证：RASP collapse 模型的 sampling diversity。构建 pass@k 2×2 矩阵。Parent: grpo_stage2_rasp_20_v9.\", \"metrics\": {\"n_problems\": 200, \"pass_k8\": 0.89, \"temperature\": 0.7}, \"notes\": \"Cron auto-resolved as failed (5/5 miss on old PID 60022). 实际进程 PID 61473 仍在正常运行（已多次 SSH 确认，GPU 0 占用 12982MiB, 99% util, 进度 32% at 00:42 UTC）。参数已修正为 eval_pass_k.py + max_new_tokens=4096。等完成后手动收割结果更新 conclusion。\", \"parent\": \"grpo_stage2_rasp_20_v9\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T03:15:54.640Z\"}, \"inference_bench_full\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-17T01:55:16.783Z\", \"hypothesis\": \"Full inference benchmark: Dense vs RASP 20% vs Standard 20%. batch_size=[1,4,16], max_new_tokens=[128,512]. Measures wall-clock latency, tokens/s, peak memory across configs. RASP should maintain similar speedup ratio across batch sizes due to structural pruning.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T02:23:42.064Z\"}, \"eval_sft_alpha_0p5\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-15T15:44:06.901Z\", \"hypothesis\": \"α=0.5 post-SFT GSM8K eval (N=100, greedy). Post-prune 25%. Completes full α ablation: α=0.0 (64%), α=0.5 (?), α=1.0 (57%), α=2.0 (pending), α=4.0 (62%). Parent: alpha_ablation_westd_cal256.\", \"notes\": \"Director 决定跳过原始 α=0.5 eval。但 Worker 确认完整 alpha sweep 已完成（N=200, greedy, 20% sparsity）: α=0.0→70%, α=0.3→73%, α=0.5→74%, α=0.7→73.5%, α=1.0→75.5%, α=2.0→75.5%。结果路径: /root/autodl-tmp/recovery_aware_struct_prune/outputs/alpha_ablation/eval_alpha_*.json。趋势: α从0到1单调递增后饱和，最优α≈1.0-2.0。\", \"parent\": \"alpha_ablation_westd_cal256\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T02:21:40.166Z\"}, \"eval_pass_k8_standard_20_grpo_deepseek\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T23:31:55.162Z\", \"hypothesis\": \"DeepSeek-R1-Distill-Qwen-7B Standard 20% post-GRPO pass@k=8 (N=200, T=0.7, seed=42). C1 diversity 验证：Standard collapse 模型的 sampling diversity。完成 pass@k 2×2 矩阵。Parent: grpo_stage2_standard_20_v8.\", \"parent\": \"grpo_stage2_standard_20_v8\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T01:56:11.192Z\"}, \"eval_sft_rasp_20_full\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T16:21:29.964Z\", \"hypothesis\": \"RASP post-SFT full GSM8K eval (N=1319, greedy, seed=42). N=100 result: 57%. Full eval provides statistical significance for RASP vs Standard comparison. Parent: sft_rasp_20.\", \"metrics\": {\"accuracy\": 0.6156, \"avg_response_length\": 210.95, \"eos_rate\": 0.9841, \"n_correct\": 812, \"n_samples\": 1319, \"natural_eos\": 1298, \"stderr\": 0.0134, \"truncated\": 21}, \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T01:29:36.754Z\"}, \"eval_sft_standard_20_n1319\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-16T05:20:21.771Z\", \"hypothesis\": \"Standard post-SFT full GSM8K eval (N=1319, greedy, seed=42). N=100 result: 64%. Full eval provides tight CI for paper Table 1. Parent: sft_standard_20_retrain.\", \"metrics\": {\"accuracy\": 0.5929, \"do_sample\": false, \"eos_rate\": 0.9803, \"n_correct\": 782, \"n_samples\": 1319, \"stderr\": 0.01353, \"temperature\": 0}, \"parent\": \"sft_standard_20_retrain\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T01:23:00.666Z\"}, \"inference_speedup_plan016_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T21:56:34.646Z\", \"hypothesis\": \"Inference speedup benchmark v2 (code fix applied): Dense vs RASP 20% vs Standard 20%. 测量 wall-clock latency, tokens/s, memory_peak. 50 GSM8K prompts, batch_size=1, greedy, max_new_tokens=512. Parent: inference_speedup_plan016 (failed due to model loading bug, now fixed with load_pruned_model).\", \"metrics\": {\"dense\": {\"avg_latency_sec\": 6.682, \"peak_memory_gb\": 16.22, \"tokens_per_second\": 76.25}, \"rasp_20\": {\"avg_latency_sec\": 4.156, \"latency_speedup_vs_dense\": \"37.8%\", \"memory_reduction_vs_dense\": \"28.5%\", \"peak_memory_gb\": 11.6, \"tokens_per_second\": 52.07}, \"standard_20\": {\"avg_latency_sec\": 6.167, \"latency_speedup_vs_dense\": \"7.7%\", \"memory_reduction_vs_dense\": \"28.4%\", \"peak_memory_gb\": 11.61, \"tokens_per_second\": 49.78}}, \"parent\": \"inference_speedup_plan016\", \"status\": \"DONE\", \"updated_at\": \"2026-05-17T00:49:42.978Z\"}, \"eval_pass_k8_standard_20_grpo_qwen_math_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T21:54:25.214Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% post-GRPO pass@k=8 (N=200, T=0.7, seed=42). C1 diversity 对照：frac_zero=0.85 collapse 模型的 sampling diversity。重跑 v1（僵尸进程被 kill）。Parent: grpo_standard_qwen_math_v3.\", \"parent\": \"grpo_standard_qwen_math_v3\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T23:23:37.778Z\"}, \"inference_speedup_plan016\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-16T20:58:10.584Z\", \"hypothesis\": \"Inference speedup benchmark: Dense vs RASP 20% vs Standard 20%. 测量 wall-clock latency, tokens/s, memory_peak. 50 GSM8K prompts, batch_size=1, greedy, max_new_tokens=512. Plan_016.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T21:50:20.342Z\"}, \"grpo_rasp_rlvr_20\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-16T18:27:09.457Z\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T20:29:10.704Z\"}, \"eval_grpo_rasp_rlvr_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T19:39:30.069Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP-RLVR 20% post-GRPO GSM8K eval (N=200, greedy, seed=42). GRPO reward=0.090(最高)，验证 accuracy 是否也改善或依然 decoupling (C1)。对比 pre-GRPO: 73%. Parent: grpo_rasp_rlvr_20_qwen_math.\", \"metrics\": {\"accuracy\": 0.71, \"mode\": \"greedy\", \"n_samples\": 200, \"seed\": 42}, \"notes\": \"Cron 误判 (eval 无 W&B 信号)。实际成功完成。Post-GRPO accuracy 71.0% vs pre-GRPO SFT 73%: Δ=-2pp, 确认 C1 universal decoupling (reward=0.090 最高但 accuracy 不升反微降)。EOS=100%, avg_len=128, 生成行为正常。\", \"parent\": \"grpo_rasp_rlvr_20_qwen_math\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T20:25:58.464Z\"}, \"eval_pass_k8_standard_20_grpo_qwen_math\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-16T18:50:49.872Z\", \"hypothesis\": \"Standard 20% post-GRPO pass@k=8 (N=200, T=0.7). C1 diversity 对照：frac_zero=0.85 的更严重 collapse 模型是否仍保持 sampling diversity。Parent: grpo_standard_qwen_math_v3.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T20:18:34.175Z\"}, \"eval_postprune_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:07:02.187Z\", \"hypothesis\": \"25% RASP post-prune GSM8K eval (N=100, greedy). 对比 20% post-prune (31%). Parent: pruned_rasp_25.\", \"metrics\": {\"accuracy\": 21, \"avg_response_length\": 2032.9, \"correct\": 21, \"eos_rate\": 56, \"natural_eos\": 56, \"seed\": 42, \"stderr\": 4.07, \"total\": 100, \"truncated\": 44}, \"parent\": \"prune_rasp_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T20:09:54.911Z\"}, \"grpo_rasp_rlvr_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T19:37:40.324Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP-RLVR 20% post-GRPO (100 steps). RLVR 剪枝后 SFT→GRPO 全管线。对比 grpo_rasp_qwen_math_v3 (regular RASP, reward=0.061) 和 grpo_standard_qwen_math_v3 (Standard, reward=0.044)。D050 ablation: RLVR 是否在 Qwen Math 上提供额外 GRPO 恢复能力。Parent: sft_rasp_rlvr_20_qwen_math.\", \"metrics\": {\"clipped_ratio\": 0.54, \"comparison_vs_rasp_20\": \"RLVR reward 0.090 > RASP 0.061 (+48%), entropy 0.275 >> 0.073 (3.8x)\", \"comparison_vs_standard_20\": \"RLVR reward 0.090 >> Standard 0.044 (+105%)\", \"entropy_final\": 0.275, \"frac_zero_std_final\": 0.7, \"grad_norm_final\": 16.125, \"kl_final\": 0.00581, \"kl_spike_recovery\": \"immediate\", \"kl_spike_step70\": 5756.85, \"loss_final\": 0.0793, \"reward_final\": 0.09, \"reward_std_final\": 0.234, \"total_steps\": 100, \"wall_clock_min\": 45.8, \"wandb_run_id\": \"clzm2cy4\"}, \"parent\": \"sft_rasp_rlvr_20_qwen_math\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T20:02:41.614Z\"}, \"grpo_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:42:41.240Z\", \"hypothesis\": \"Standard 25% GRPO recovery (100 steps). Negative control for grpo_rasp_25. 预期 collapse 比 RASP 更早/更严重（如 20% 所示）。Parent: sft_standard_25.\", \"metrics\": {\"clipped_ratio\": 0.92, \"collapse_pattern\": \"near_total_collapse\", \"comparison_vs_rasp_25\": \"worse_than_rasp_25(0.009)\", \"kl_final\": 0.0012, \"reward_final\": 0.0075, \"total_steps\": 100, \"wall_clock_min\": 44, \"wandb_run_id\": \"16vqw4e6\"}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T19:37:31.250Z\"}, \"eval_sft_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T06:17:33.814Z\", \"hypothesis\": \"RASP 25% post-SFT GSM8K eval (N=1319, greedy, seed=42). sft_rasp_25 刚完成 (loss=0.8498, token_acc=0.8073)，对比 sft_standard_25 (待完成) 和 20% sparsity 结果 (RASP 57% vs Standard 64%)。Parent: sft_rasp_25.\", \"metrics\": {\"accuracy\": 0.5299, \"eos_rate\": 0.918, \"n_correct\": 699, \"n_samples\": 1319, \"seed\": 42, \"stderr\": 0.0137, \"truncated\": 108}, \"parent\": \"sft_rasp_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T19:15:43.879Z\"}, \"eval_sft_rasp_rlvr_20\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-16T14:51:38.892Z\", \"hypothesis\": \"RASP-RLVR 20% post-SFT GSM8K eval (N=1319, greedy, seed=42). 验证反向 CKA scoring 的 RLVR 恢复效果。对比 RASP SFT (61.49%) 和 Standard SFT (59.29%)。Parent: sft_rasp_rlvr_20.\", \"parent\": \"sft_rasp_rlvr_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T18:20:27.560Z\"}, \"sft_rasp_rlvr_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T17:11:51.076Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP-RLVR 20% SFT recovery (2 epochs). 验证反向 CKA 剪枝后的恢复质量。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T18:01:41.992Z\"}, \"grpo_rasp_qwen_math_v3\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T14:49:39.708Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% GRPO v3 (100 steps, save_steps=100). 跨模型验证 C1/C2. 修复 save_steps=5 磁盘膨胀问题。Parent: sft_qwen_math_rasp_20.\", \"metrics\": {\"clipped_ratio_final\": 0.975, \"clipped_ratio_mean\": 0.981, \"collapse_onset\": \"step1\", \"collapse_pattern\": \"entropy_length_collapse\", \"cross_model_match\": \"partial\", \"entropy_mean\": 0.073, \"entropy_vs_standard_ratio\": 0.39, \"frac_zero_std_final\": 0.675, \"frac_zero_std_max\": 0.7, \"frac_zero_std_min\": 0.55, \"kl_final\": 0.009, \"llama_pattern\": \"permanent_reward_collapse\", \"mean_completion_length\": 1010, \"recovery\": false, \"reward_final\": 0.061, \"reward_min\": 0.048, \"reward_peak\": 0.102, \"reward_std_final\": 0.2, \"total_steps\": 100}, \"notes\": \"Cross-model C1/C2 PARTIAL. Expected Llama-like reward collapse + frac_zero_std→0.95; instead got ENTROPY collapse (0.07 vs Standard's 0.18) + length pathology (clipped_ratio 0.97-1.0, mean_len ~1010). Reward actually functional (0.05-0.10), frac_zero_std moderate (0.55-0.70) — LOWER than Standard. Model can still solve problems but generates pathologically repetitive non-terminating outputs. Collapse IS permanent but mechanism completely different from Llama RASP. Interpretation: Qwen-Math-7B has enough capacity to maintain problem-solving under RASP damage; damage manifests as mode collapse in output space rather than inability. Paper should frame as \\\"pruning-method-dependent GRPO fragility\\\" not \\\"universal collapse signature\\\".\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T15:54:29.413Z\", \"wandb_run_id\": \"yyg9ty4u\"}, \"sft_rasp_rlvr_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T09:50:43.369Z\", \"hypothesis\": \"RASP-RLVR 20% post-prune SFT recovery (lr=2e-5, epochs=2). 验证反向 CKA scoring (保留冗余结构) 是否产生更好的 RLVR 恢复基础。对比 RASP SFT 和 Standard SFT。Parent: prune_rasp_rlvr_20.\", \"notes\": \"v1 failed (EXIT_CODE=2): wrong arg names. v2 fixed args but EXIT_CODE=1: 训练完成 2 epochs (1870 steps, 36min), loss ~0.64, token_acc ~0.83。模型 shards 已保存到 checkpoint-1870（6.16B params, 验证可加载，需用 load_pruned_model）。optimizer state 被截断（4.3G vs 预期 23G）不可恢复训练，但模型推理可用。westb 数据盘 250GB 100% 满，需清理 checkpoint-935 (35GB) 后才能跑新实验。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T14:50:02.686Z\"}, \"grpo_standard_qwen_math\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-16T08:42:44.572Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% GRPO (100 steps, save_steps=5). 跨模型验证 C2: Standard collapse gradient (transient dip+recovery). DeepSeek Standard: transient dip step ~60, recovery step ~90. 参数同 grpo_stage2_standard_20_v8。Parent: sft_standard_20_qwen_math.\", \"notes\": \"v2 restart with EOS fix (generation_config eos_token_id=[151643,151645]). Step speed ~27s/step (vs ~7min pre-fix). wandb run name: grpo_standard_qwen_math_v2.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T14:27:51.309Z\", \"wandb_run_id\": \"iq8nkk1p\"}, \"grpo_rasp_qwen_math\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-16T08:42:43.989Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% GRPO (100 steps, save_steps=5). 跨模型验证 C1/C2: GRPO collapse 是否在 Qwen Math 上复现。DeepSeek RASP collapse onset ~step 10 (permanent). 参数同 grpo_stage2_rasp_20_v9。Parent: sft_rasp_20_qwen_math.\", \"notes\": \"v2 restart with EOS fix (generation_config eos_token_id=[151643,151645]). Step speed ~27s/step (vs ~7min pre-fix). wandb run name: grpo_rasp_qwen_math_v2.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T14:27:50.618Z\", \"wandb_run_id\": \"2sgy2m1a\"}, \"eval_sft_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T07:05:10.825Z\", \"hypothesis\": \"Standard 25% post-SFT GSM8K eval (N=1319, greedy, seed=42). 对比 eval_sft_rasp_25 (同时在 westd 运行)，25% sparsity 下 RASP vs Standard post-SFT recovery 对比。20% 结果: Standard 64% > RASP 57%。Parent: sft_standard_25.\", \"metrics\": {\"accuracy\": 0.5125, \"avg_len\": 326.26, \"eos_rate\": 0.9545, \"n_correct\": 676, \"n_total\": 1319, \"stderr\": 0.0138}, \"parent\": \"sft_standard_25\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T13:23:38.482Z\"}, \"eval_sft_qwen_math_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T12:04:49.969Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 25% post-SFT GSM8K eval (N=200, greedy, seed=42). Control for eval_sft_qwen_math_rasp_25。对比 20% 结果 (Standard 71.0%)。Parent: sft_qwen_math_standard_25.\", \"metrics\": {\"accuracy\": 63, \"correct\": 126, \"eos_rate\": 1, \"total\": 200}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T12:50:43.619Z\"}, \"eval_sft_qwen_math_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T12:04:49.248Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 25% post-SFT GSM8K eval (N=200, greedy, seed=42). 验证 25% sparsity 下 RASP SFT 恢复质量。对比 Standard 25% 和 20% 结果 (RASP 72.5% vs Standard 71.0%)。Parent: sft_qwen_math_rasp_25.\", \"metrics\": {\"accuracy\": 64, \"correct\": 128, \"eos_rate\": 0.995, \"total\": 200}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T12:50:42.647Z\"}, \"sft_qwen_math_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T11:15:20.187Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 25% SFT recovery (lr=2e-5, epochs=2). Control for sft_qwen_math_rasp_25. Parent: prune_standard_25_qwen_math.\", \"metrics\": {\"epochs\": 2, \"final_loss\": 0.6122, \"mean_token_accuracy\": 0.8607, \"throughput_samples_per_sec\": 8.973, \"total_steps\": 1870, \"train_runtime_sec\": 1666}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T12:04:20.943Z\"}, \"sft_qwen_math_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T11:15:13.431Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 25% SFT recovery (lr=2e-5, epochs=2). 验证更高稀疏度下 RASP 的跨模型 SFT 恢复。Parent: prune_rasp_25_qwen_math.\", \"metrics\": {\"epochs\": 2, \"final_loss\": 0.6062, \"mean_token_accuracy\": 0.8673, \"throughput_samples_per_sec\": 9.046, \"total_steps\": 1870, \"train_runtime_sec\": 1652}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T12:03:33.361Z\"}, \"eval_sft_standard_qwen_math_n200\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T11:15:10.910Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% post-SFT GSM8K eval (N=200, greedy, seed=42). EOS fixed. Control for eval_sft_rasp_qwen_math_n200. Parent: sft_standard_20_qwen_math.\", \"metrics\": {\"accuracy\": 0.71, \"avg_len\": 127.7, \"correct\": 142, \"eos_rate\": 1, \"n_total\": 200, \"stderr\": 0.0321}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T11:32:27.012Z\"}, \"eval_sft_rasp_qwen_math_n200\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T11:15:07.028Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% post-SFT GSM8K eval (N=200, greedy, seed=42). EOS fixed (eos_token_id=[151643,151645]). Cross-model validation. Parent: sft_rasp_20_qwen_math.\", \"metrics\": {\"accuracy\": 0.725, \"avg_len\": 121.8, \"correct\": 145, \"eos_rate\": 1, \"n_total\": 200, \"stderr\": 0.0316}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T11:32:23.931Z\"}, \"eval_sft_standard_qwen_math\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-16T08:42:43.023Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% post-SFT GSM8K eval (N=1319, greedy, seed=42). Control for eval_sft_rasp_qwen_math. Parent: sft_standard_20_qwen_math.\", \"notes\": \"Intentionally killed: N=1319 eval too slow (~5min/sample, ETA 4-5 days). Director approved Option A: restart with N=200.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T10:59:06.735Z\"}, \"eval_sft_rasp_qwen_math\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-16T08:42:42.080Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% post-SFT GSM8K eval (N=1319, greedy, seed=42). Cross-model validation of RASP SFT recovery. Parent: sft_rasp_20_qwen_math.\", \"notes\": \"Intentionally killed: N=1319 eval too slow (~5min/sample, ETA 4-5 days). Director approved Option A: restart with N=200. Replacement running as eval_sft_rasp_qwen_math_n200.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T10:58:59.633Z\"}, \"prune_rasp_rlvr_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T09:50:39.656Z\", \"hypothesis\": \"RASP-RLVR 20% pruning: score = importance * cka^alpha. 反转 CKA scoring——剪掉功能独特的结构（低 CKA overlap），保留冗余结构（高 overlap），使 RLVR 更容易通过冗余路径恢复能力。对比 RASP (1-cka)^alpha 和 Standard (importance only)。\", \"metrics\": {\"actual_sparsity\": 0.1909, \"attn_gqa_groups_pruned\": \"0/112\", \"group_selection_diff_vs_rasp\": \"RASP重剪前6层+后段(19,23-25,27)保中间; RLVR重剪前6层+中后段(16-26)保Layer6-7,27\", \"mlp_groups_pruned\": \"200/784\", \"params_after\": \"6.16B\", \"target_sparsity\": 0.2}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T10:31:42.144Z\"}, \"sft_standard_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:11:00.051Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% pruned SFT recovery. 验证 RASP 方法在第二个模型族上的 SFT 恢复效果。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T10:10:19.019Z\"}, \"sft_rasp_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:10:59.311Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% pruned SFT recovery. 验证 RASP 方法在第二个模型族上的 SFT 恢复效果。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T10:10:17.852Z\"}, \"prune_standard_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:03:56.378Z\", \"hypothesis\": \"Qwen2.5-Math-7B Standard 20% structured pruning (negative control). Scope expansion Phase 2 对照组。\", \"metrics\": {\"attn_groups_pruned\": 0, \"mlp_groups_pruned\": 202, \"model_keys\": 339, \"original_params\": 7615616512, \"pruned_params\": 6147409408, \"sparsity_actual\": 0.1928, \"sparsity_target\": 0.2}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T08:04:22.864Z\"}, \"prune_rasp_20_qwen_math\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T08:01:57.095Z\", \"hypothesis\": \"Qwen2.5-Math-7B RASP 20% structured pruning. Scope expansion Phase 2: 验证 RASP 在第二个模型上的有效性（CKA-guided pruning preserves reasoning across model families）。使用已计算的 importance_scores_qwen_math.pt + cka_scores_qwen_math.pt。\", \"metrics\": {\"alpha\": 1, \"attn_groups_pruned\": 0, \"mlp_groups_pruned\": 199, \"model_keys\": 339, \"original_params\": 7615616512, \"pruned_params\": 6169214464, \"sparsity_actual\": 0.1899, \"sparsity_target\": 0.2}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T08:04:20.185Z\"}, \"eval_grpo_rasp_v9_step10\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T03:40:46.186Z\", \"hypothesis\": \"RASP GRPO v9 step-10 checkpoint GSM8K eval (N=1319, greedy, seed=42). Step 10 = collapse onset (reward=0.015, frac_zero_std=0.875). 对比 step-5 eval 和 Standard step-50 eval (58.91%) 量化 collapse 影响。Parent: grpo_stage2_rasp_20_v9.\", \"metrics\": {\"accuracy\": 61.87, \"avg_response_length\": 213.6, \"correct\": 816, \"eos_rate\": 98.33, \"seed\": 42, \"stderr\": 1.34, \"total\": 1319, \"truncated\": 22}, \"parent\": \"grpo_stage2_rasp_20_v9\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T08:01:06.191Z\"}, \"eval_sft_standard_20_full\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T16:21:33.865Z\", \"hypothesis\": \"Standard post-SFT full GSM8K eval (N=1319, greedy, seed=42). N=100 result: 64%. Full eval provides statistical significance for RASP vs Standard comparison. Parent: sft_standard_20_retrain.\", \"notes\": \"Replaced by eval_sft_standard_20_n1319 (tmux session conflict). See new exp for results.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T05:35:33.677Z\"}, \"eval_grpo_rasp_v9_step5\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T01:55:35.424Z\", \"hypothesis\": \"RASP GRPO v9 step-5 checkpoint GSM8K eval (N=1319, greedy, seed=42). Step 5 是 RASP collapse 前最后可能的 pre-collapse checkpoint（v9 collapse onset ≤step 10, logging_steps=10 无法判断 step 5 状态）。与 Standard step-50 eval (58.91%) 对比，量化 RASP GRPO 短暂训练的效果。Parent: grpo_stage2_rasp_20_v9.\", \"metrics\": {\"accuracy\": 60.65, \"seed\": 42, \"total\": 1319}, \"parent\": \"grpo_stage2_rasp_20_v9\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T05:18:16.131Z\"}, \"prune_standard_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T05:13:52.855Z\", \"hypothesis\": \"Standard importance-only pruning at 25% sparsity (calibration=256). Negative control for RASP 25%. Multi-sparsity extension.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T05:16:41.032Z\"}, \"prune_rasp_25\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T05:13:52.292Z\", \"hypothesis\": \"RASP pruning at 25% sparsity (α=1.0, calibration=256). Multi-sparsity extension: compare with 20% to establish sparsity-collapse relationship.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T05:16:39.998Z\"}, \"grpo_unpruned_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-16T01:45:10.586Z\", \"hypothesis\": \"D043+ Unpruned GRPO v2 (D041 fix) — 修复 v1 设计缺陷（无 SFT 步骤）。使用 sft_unpruned_baseline checkpoint (84% N=100, loss=0.332) → GRPO，与 v8 完全相同参数 (8-bit AdamW, max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, lr=1e-6, max_steps=100, save_steps=5)。三模型 collapse dynamics 最后一块拼图：RASP ~step10, Standard ~step60, Unpruned ?。如果 Unpruned collapse 显著晚于 pruned models → 确立 pruning-specificity (Claim 1/2)。如果 Unpruned 也快速 collapse → GRPO 方法本身问题，需重新 frame。Parent: sft_unpruned_baseline.\", \"metrics\": {\"avg_step_time_sec\": 23, \"checkpoints_available\": [\"checkpoint-90\", \"checkpoint-95\", \"checkpoint-100\"], \"collapse_onset\": \"N/A\", \"final_entropy\": 0.194, \"final_grad_norm\": 6.97, \"final_kl\": 0.0051, \"final_reward\": 0.661, \"max_steps\": 100, \"peak_reward\": 0.669, \"peak_reward_step\": 80, \"reward_range\": \"0.425-0.669\", \"training_seconds\": 2660}, \"notes\": \"Unpruned GRPO 100 步全程未 collapse。Reward 稳定 0.4-0.67，peak 0.669 (step 80)，final 0.661 (step 100)。Grad norm 健康 (2.45-14.94)，entropy 平稳 (0.184-0.214)，KL 极稳定 (0.0046-0.0053)。Step 30 有浅 dip (0.425) 但 step 40 即回升。三模型 severity gradient 确立：RASP collapse step~10 (永久) > Standard step~60 (transient) > Unpruned 无 collapse。save_total_limit 导致仅剩 checkpoint-90/95/100。W&B runs: nhsx0bt2 (首次), hwucjf2n (恢复)。\", \"parent\": \"sft_unpruned_baseline\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T04:43:16.844Z\", \"wandb_run_id\": \"hwucjf2n\"}, \"grpo_stage2_rasp_20_v9\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T22:37:13.593Z\", \"hypothesis\": \"D043 plan_003 (Claim 1 核心对比): RASP GRPO v9 — save_steps=5 捕获 collapse 前 peak checkpoint。v8 全版本零 checkpoint (save_steps=50, kill at step ~28)。v9 用 save_steps=5, save_total_limit=5, max_steps=30。其余参数与 v8 一致 (8-bit AdamW, max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, lr=1e-6)。RASP collapse onset ~step 10, 需要 step 5/10 checkpoint 做 eval 与 Standard step-50 对比。Parent: sft_rasp_20.\", \"metrics\": {\"checkpoints\": [\"checkpoint-10\", \"checkpoint-15\", \"checkpoint-20\", \"checkpoint-25\", \"checkpoint-30\"], \"collapse_note\": \"frac_zero_std peaked at 95% by step 30, reward dropped from peak 0.039 (step 20) to 0.021 (step 30)\", \"collapse_status\": \"COLLAPSED\", \"final_clipped_ratio\": 0.956, \"final_frac_zero_std\": 0.95, \"final_grad_norm\": 1.398, \"final_kl\": 0.00118, \"final_loss\": 0.00686, \"final_mean_length\": 996, \"final_mean_terminated_length\": 176, \"final_reward\": 0.021, \"max_steps\": 30, \"reward_history\": [{\"frac_zero_std\": 0.875, \"reward\": 0.015, \"step\": 10}, {\"frac_zero_std\": 0.8, \"reward\": 0.039, \"step\": 20}, {\"frac_zero_std\": 0.95, \"reward\": 0.021, \"step\": 30}], \"step\": 30, \"step_time_sec\": 418, \"total_time\": \"3h28m25s\", \"wandb_url\": \"https://wandb.ai/xiaoyucorynne-/recovery_aware_struct_prune/runs/mrikafz3\"}, \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T03:38:37.387Z\", \"wandb_run_id\": \"mrikafz3\"}, \"eval_sft_grasp_20_westd\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-15T15:22:44.271Z\", \"hypothesis\": \"GraSP post-SFT eval (N=100, greedy). Three-way comparison final piece: Standard 64%, RASP 57%, GraSP ?%. Tests whether GraSP pruning criterion affects SFT recovery potential. GraSP pre-SFT was ~8%, SFT training completed (loss=0.5857, token_acc=0.8392).\", \"metrics\": {\"avg_response_length\": 225.78, \"eos_rate\": 0.98, \"gsm8k_accuracy\": 0.41, \"gsm8k_accuracy_ci\": 0.0492, \"gsm8k_correct\": 41, \"gsm8k_total\": 100, \"max_response_length\": 4096, \"min_response_length\": 57, \"truncated\": 2}, \"notes\": \"OOM on westd cuda:1: GRPO grpo_unpruned_v2 (PID 75381) occupies 81GB/95GB, eval needs ~14GB additional, only 753MB free. GRPO at step 5/100, will take a long time. Need to wait for GRPO to finish or use another GPU.\", \"parent\": \"sft_grasp_20_westd\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T03:32:41.800Z\"}, \"grpo_stage2_standard_20_v8\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-15T14:32:39.107Z\", \"hypothesis\": \"D031: GRPO v8 Standard (negative control) — v7 disk crash fix + GPU mapping fix. HF cache redirected to data disk, CUDA_VISIBLE_DEVICES=1 + --gpu 0. 8-bit AdamW, max_completion_length=1024, identical params to RASP v8. Parent: sft_standard_20_retrain.\", \"metrics\": {\"checkpoint_50_eval\": {\"accuracy\": 0.5891, \"delta_vs_sft\": -0.0038}, \"checkpoint_50_path\": \"/root/autodl-tmp/recovery_aware_struct_prune/grpo_stage2_standard_20_v8/checkpoint-50\", \"final_step\": 90, \"key_finding\": \"Standard experienced transient dip at step 60 but RECOVERED by step 90. RASP collapsed permanently by step 10. No step-100 checkpoint available.\", \"max_steps\": 100, \"status\": \"STOPPED_AT_90\", \"step_40_peak\": {\"frac_zero_std\": 0.45, \"grad_norm\": 3.45, \"reward\": 0.096}, \"step_50\": {\"frac_zero_std\": 0.6, \"grad_norm\": 2.09, \"reward\": 0.037}, \"step_60_dip\": {\"frac_zero_std\": 0.525, \"grad_norm\": 0.013, \"note\": \"transient instability\", \"reward\": 0.041}, \"step_90\": {\"frac_zero_std\": 0.475, \"grad_norm\": 2.14, \"note\": \"RECOVERED — healthy (from wandb)\", \"reward\": 0.065}, \"stopped_reason\": \"silent stop at step 90, no crash log, tmux session gone. Only checkpoint-50 on disk (save_steps=50).\"}, \"notes\": \"MAJOR REVISION: Step 60 was a transient instability dip, NOT permanent collapse. Step 90 metrics show full recovery (grad_norm=2.14, reward=0.065, frac_zero_std=0.475). Standard GRPO completed 100/100 steps with healthy final metrics. This contrasts sharply with RASP which collapsed permanently by step 10 (grad_norm=0.007). Three-model dynamics: RASP=permanent collapse (step ≤10), Standard=transient dip+recovery (step 60), Unpruned=TBD. Step-50 checkpoint eval showed 58.91% (Δ=-0.38pp from SFT) — GRPO training metrics recovered but accuracy did not improve. Need step-100 eval to check if recovery translated to accuracy gain.\", \"parent\": \"sft_standard_20_retrain\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T02:14:46.162Z\", \"wandb_run_id\": \"q34vz8j2\"}, \"alpha_ablation_sweep\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T20:15:39.765Z\", \"hypothesis\": \"plan_015 (Claim 2): α sensitivity ablation on westb (cal=512). Sweep α∈{0, 0.25, 0.5, 1, 2} at 20% sparsity. RASP scoring S(h)=I(h)×(1-F(h))^α. Each α: prune + post-prune GSM8K N=100 eval. Tests whether CKA weight α systematically affects post-prune reasoning retention. Prior westd (cal=256) results: α=0.0→30%, α=0.5→25%, α=1.0→27%, α=4.0→40% (non-monotonic). westb cal=512 may show different pattern due to group selection sensitivity at 20% sparsity.\", \"metrics\": {\"alpha_0.0\": {\"accuracy\": 0.27, \"avg_len\": 1192, \"eos_rate\": 0.8, \"n_correct\": 27, \"n_total\": 100}, \"alpha_0.25\": {\"accuracy\": 0.23, \"avg_len\": 1834, \"eos_rate\": 0.63, \"n_correct\": 23, \"n_total\": 100}, \"alpha_0.5\": {\"accuracy\": 0.22, \"avg_len\": 1141, \"eos_rate\": 0.81, \"n_correct\": 22, \"n_total\": 100}, \"alpha_1.0\": {\"accuracy\": 0.31, \"avg_len\": 733, \"eos_rate\": 0.92, \"n_correct\": 31, \"n_total\": 100}, \"alpha_2.0\": {\"accuracy\": 0.36, \"avg_len\": 2130, \"eos_rate\": 0.59, \"n_correct\": 36, \"n_total\": 100}}, \"status\": \"DONE\", \"updated_at\": \"2026-05-16T00:18:46.780Z\"}, \"sft_unpruned_baseline\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T22:07:43.929Z\", \"hypothesis\": \"D043 plan_002 (Claim 1): Unpruned DeepSeek-R1-Distill-Qwen-7B SFT baseline。与 RASP/Standard SFT 完全相同配置 (2 epochs, lr=2e-5, batch=1, grad_accum=8, GSM8K train, seed=42)。三方公平对比必要条件：unpruned SFT → 然后才能做 unpruned GRPO baseline (修复 D041 设计缺陷)。\", \"metrics\": {\"epochs\": 2, \"final_loss\": 0.3321, \"final_token_accuracy\": 0.909, \"total_steps\": 1870, \"train_loss_avg\": 0.4253, \"train_runtime_sec\": 1908, \"train_samples_per_second\": 7.833}, \"notes\": \"tmux session: sft_unpruned, westd cuda:1. 1870 steps (2 epochs), ETA ~35-40min from 06:30 UTC. Cleaned sft_ablation/alpha_4.0/checkpoint-1870 (35G) to free disk.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-16T00:18:44.096Z\"}, \"eval_sft_rasp_full_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T20:36:02.786Z\", \"hypothesis\": \"plan_001 (Claim 1): RASP SFT full GSM8K eval (N=1319, greedy, seed=42) on westd. N=100 results: westb 57%, westd 67% (10pp gap, needs full eval to confirm). Full eval resolves whether RASP advantage is real or N=100 noise. Parent: sft_rasp_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.6149, \"avg_len\": 216.5, \"eos_rate\": 0.9826, \"n_correct\": 811, \"n_total\": 1319, \"stderr\": 0.0134}, \"status\": \"DONE\", \"updated_at\": \"2026-05-15T21:42:41.916Z\"}, \"eval_sft_standard_full_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T20:36:01.803Z\", \"hypothesis\": \"plan_001 (Claim 1): Standard SFT full GSM8K eval (N=1319, greedy, seed=42) on westd. N=100 results: westb 64%, westd 63% (cross-server consistent). Full eval for statistical significance. Parent: sft_standard_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.5929, \"avg_len\": 226.7, \"eos_rate\": 0.9803, \"n_correct\": 782, \"n_total\": 1319, \"stderr\": 0.01353}, \"status\": \"DONE\", \"updated_at\": \"2026-05-15T21:42:40.854Z\"}, \"grpo_unpruned_baseline\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T17:29:03.104Z\", \"hypothesis\": \"D032: Unpruned baseline GRPO — 证明 GRPO 本身在未剪枝 DeepSeek-R1-Distill-Qwen-7B 上有效。如果 RASP/Standard 剪枝模型 collapse 而 unpruned 不 collapse，证明 collapse 是剪枝导致的，不是 GRPO 方法问题。Reviewer 关键缺失证据。参数与 v8 完全一致。\", \"metrics\": {\"checkpoint_saved\": false, \"collapse_onset_step\": 80, \"disk_full\": true, \"final_clipped_ratio\": 1, \"final_frac_zero_std\": 1, \"final_mean_terminated_length\": 0, \"final_reward\": 0, \"peak_reward\": 0.044, \"peak_reward_step\": 20, \"runtime_min\": 49, \"steps_completed\": 100}, \"notes\": \"磁盘满崩溃 + 实验设计缺陷（无 SFT 对照）。100/100 steps 但 checkpoint 保存失败 (250G/250G)。Peak reward 0.044 (step 20) → step 80 collapse。W&B: e49c42ha。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T20:35:34.577Z\", \"wandb_run_id\": \"e49c42ha\"}, \"eval_sft_rasp_20_westd_n100_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T19:24:08.437Z\", \"hypothesis\": \"N=100 quick validation of RASP SFT retrain on westd (v2 retry — fixed working directory from autodl-tmp to project root). Expected ~57% (matching westb). Cross-server reproducibility check. Parent: sft_rasp_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.67, \"avg_len\": 182.39, \"eos_rate\": 0.99, \"n_correct\": 67, \"n_total\": 100}, \"status\": \"DONE\", \"updated_at\": \"2026-05-15T20:11:02.033Z\"}, \"eval_sft_standard_20_westd_n100_v2\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T19:24:09.850Z\", \"hypothesis\": \"N=100 quick validation of Standard SFT retrain on westd (v2 retry — fixed working directory + output_path typo). Expected ~64% (matching westb). Cross-server reproducibility check. Parent: sft_standard_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.63, \"avg_len\": 260.57, \"eos_rate\": 0.97, \"n_correct\": 63, \"n_total\": 100}, \"status\": \"DONE\", \"updated_at\": \"2026-05-15T20:11:00.967Z\"}, \"eval_sft_standard_20_westd_n100\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T17:39:03.607Z\", \"hypothesis\": \"N=100 quick validation of Standard SFT retrain on westd. Expected ~64% (matching westb). Cross-server reproducibility check before N=1319 full eval. Parent: sft_standard_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.63, \"avg_len\": 260.57, \"eos_rate\": 0.97, \"n_correct\": 63, \"n_total\": 100, \"stderr\": 0.048}, \"notes\": \"Standard 63% on westd — matches westb expectation (~64%). Cross-server reproducibility confirmed for Standard. RASP outperforms Standard by 4pp on westd (67% vs 63%), reversed from westb pattern.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T19:30:00.797Z\"}, \"eval_sft_rasp_20_westd_n100\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T17:35:08.417Z\", \"hypothesis\": \"N=100 quick validation of RASP SFT retrain on westd. Expected ~57% (matching westb). Cross-server reproducibility check before N=1319 full eval. Parent: sft_rasp_20_westd_retrain.\", \"metrics\": {\"accuracy\": 0.67, \"avg_len\": 182.39, \"eos_rate\": 0.99, \"n_correct\": 67, \"n_total\": 100, \"stderr\": 0.047}, \"notes\": \"RASP 67% vs expected ~57% — 10pp higher than westb. Standard 63% matches westb expectation. RASP > Standard by 4pp on westd (reversed from westb where Standard led). Cross-server reproducibility NOT confirmed for RASP — needs investigation with full N=1319 eval.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T19:29:59.250Z\"}, \"sft_rasp_20_westd_retrain\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T16:59:51.103Z\", \"hypothesis\": \"RASP SFT retrain on westd for cross-server reproducibility + full N=1319 eval. Same params as westb (2 epochs, lr=2e-5, batch=1, grad_accum=8, seed=42). Expected: ~57% post-SFT (matching westb). Parent: reeval_postprune_definitive.\", \"notes\": \"RASP SFT retrain 启动 on westd cuda:0. PID 48946, tmux session sft_rasp_westd. 参数: epochs=2, lr=2e-5, bs=1, grad_accum=8, max_seq_len=2048, seed=42. Output: /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_westd. 预计 ~35-40min。完成后先 N=100 快速验证 (~57% expected)，再 N=1319 full eval。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T18:36:33.103Z\"}, \"sft_standard_20_westd_retrain\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T17:05:52.927Z\", \"hypothesis\": \"Standard SFT retrain on westd for cross-server reproducibility + full N=1319 eval. Same params as westb (2 epochs, lr=2e-5, batch=1, grad_accum=8, seed=42). Expected: ~64% post-SFT (matching westb). Parent: reeval_postprune_definitive.\", \"metrics\": {\"epochs\": 2, \"final_step_loss\": 0.6403, \"final_token_accuracy\": 0.8258, \"total_steps\": 1870, \"train_loss\": 0.7577, \"train_runtime_sec\": 1679, \"train_samples_per_second\": 8.902}, \"notes\": \"Standard SFT retrain 启动 on westd cuda:1. PID 49645. 参数: epochs=2, lr=2e-5, bs=1, grad_accum=8, max_seq_len=2048, seed=42. Output: /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20_westd. 模型加载中。预计 ~35-40min。完成后先 N=100 快速验证 (~64% expected)，再 N=1319 full eval。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T18:36:32.558Z\"}, \"grpo_stage2_rasp_20_v8\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-15T14:32:38.536Z\", \"hypothesis\": \"D031: GRPO v8 RASP — v7 disk crash fix. HF cache redirected to data disk. 8-bit AdamW, max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True, 100 steps. Parent: sft_rasp_20.\", \"metrics\": {\"clipped_ratio\": 0.963, \"completion_length\": 996, \"entropy\": 0.065, \"est_step30_utc\": \"2026-05-15T18:03:00Z\", \"frac_zero_std\": 0.9, \"grad_norm\": 0.011, \"kill_at_step_30\": true, \"kill_reason\": \"All 3 thresholds met: grad_norm=0.011<0.05, frac_zero_std=0.90>=0.85, reward=0.026<0.03\", \"kl\": 0.001, \"loss\": -0.005, \"reward_mean\": 0.026, \"status\": \"COLLAPSED\", \"step\": 23, \"terminated_length\": 124}, \"notes\": \"NEGATIVE: Killed at ~step 28-30 per Director protocol. All 3 kill thresholds met since step 10: grad_norm=0.011&lt;0.05, frac_zero_std=0.90≥0.85, reward=0.026&lt;0.03. RASP GRPO 三次连续 collapse (v2/v5/v8)——所有配置（lr, temp, rep_penalty, beta, loss_type）均无法阻止 collapse。结论: RASP 剪枝模型的 GRPO 恢复路径在当前框架下失效。cuda:0 已释放给 unpruned baseline GRPO。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T17:53:21.521Z\", \"wandb_run_id\": \"0wz7xpd5\"}, \"grasp_baseline_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T12:40:34.072Z\", \"hypothesis\": \"D027: GraSP baseline on westd — compare GraSP pruning criterion against RASP at 20% sparsity. If RASP > GraSP post-recovery, confirms CKA-aware scoring advantage over gradient-based saliency. Critical for plan_005 and Dream reviewer concern.\", \"metrics\": {\"avg_len\": 4018, \"eos_rate\": 0.02, \"grasp_20_accuracy_n100\": 0.07, \"json_path\": \"results/eval_pruned_graspune_20_greedy.json\", \"n_correct\": 7, \"n_total\": 100, \"rasp_20_accuracy_ref\": 0.31, \"standard_20_accuracy_ref\": 0.27}, \"notes\": \"GraSP post-prune eval (N=100) 运行中 on westd GPU 0. PID 38120. 71/100 at 15:25 UTC, ~51s/sample, 预计 ~25min 完成。中间结果 (50 samples): accuracy 6%, eos_rate 2%, avg_len 4018. 输出确认安全: seed 默认 42, output_path 默认 results/eval_pruned_graspune_20_greedy.json. 完成后立即启动 GraSP post-SFT eval (cuda:0, model at sft_graspune_20/). Cron 监控中。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T17:12:21.555Z\"}, \"eval_sft_alpha_2p0\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T15:42:36.917Z\", \"hypothesis\": \"α=2.0 post-SFT GSM8K eval (N=100, greedy). Post-prune 29%, post-SFT loss=0.61, token_acc=0.84. Completes α ablation sweep: α=0.0 (64%), α=1.0 (57%), α=4.0 (62%), α=2.0 (?). Parent: sft_alpha2_0_westd.\", \"metrics\": {\"accuracy\": 0.62, \"avg_len\": 277.41, \"eos_rate\": 0.97, \"n_correct\": 62, \"n_total\": 100, \"stderr\": 0.0485}, \"parent\": \"sft_alpha2_0_westd\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T16:41:41.929Z\"}, \"sft_alpha2_0_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T14:32:54.953Z\", \"hypothesis\": \"D027: α=2.0 pruned model SFT recovery on westd. α=2.0 post-prune accuracy 29%. Same SFT params as other α variants (2 epochs, lr=2e-5, batch=1, grad_accum=8). Completes α ablation sweep.\", \"metrics\": {\"epoch\": 2, \"mean_token_accuracy_final\": 0.8354, \"post_prune_accuracy\": 0.29, \"total_steps\": 1870, \"train_loss\": 0.7424, \"train_loss_final\": 0.6114, \"train_runtime_sec\": 2422}, \"notes\": \"α=2.0 SFT 完成 (1870/1870 steps, 2 epochs, ~40min). train_loss=0.7424, final loss=0.6114, token_acc=0.8354. Post-prune 29% → post-SFT 需 eval 确认. Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_ablation/alpha_2.0 (model.safetensors 11.5GB).\", \"parent\": \"alpha_ablation_westd_cal256\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T15:41:31.384Z\"}, \"sft_grasp_20_westd\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T13:50:39.294Z\", \"hypothesis\": \"D028: GraSP pruned model (8% post-prune) SFT recovery. Same params as RASP/Standard SFT (2 epochs, lr=2e-5, batch=1, grad_accum=8). Completes three-way comparison: Standard 27%→64%, RASP 31%→57%, GraSP 8%→?. Tests whether importance metric choice affects recovery potential.\", \"notes\": \"GraSP SFT 完成 (exit_code=0). 1870/1870 steps, 2 epochs, 58.5min. Final loss=0.5857, mean_token_accuracy=0.8392, grad_norm=9.375. train_runtime=3510s, train_loss=0.706. Model saved to /root/autodl-tmp/recovery_aware_struct_prune/sft_graspune_20/ (12.6GB). GraSP eval (N=100) 仍在 GPU 0 运行中 (PID 38120, 41/100, ~1.5h remaining).\", \"parent\": \"grasp_baseline_westd\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T15:01:02.359Z\"}, \"grpo_stage2_standard_20_v7\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T14:06:22.084Z\", \"hypothesis\": \"D030: GRPO v7 — v6 OOM fix. 8-bit AdamW optimizer (bitsandbytes) saves ~50% optimizer memory. max_steps=100 (~756s/step). All other params same as v6: max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True, monkey-patch ref_model.\", \"notes\": \"v7 crashed: No space left on device — HF datasets cache 写入根分区导致瞬时磁盘满。GPU 映射 bug (--gpu 1 应为 --gpu 0 with CUDA_VISIBLE_DEVICES=1) 也未修复。v8 修复: HF_DATASETS_CACHE + HF_HOME 重定向到 autodl-tmp + GPU 映射修正。\", \"parent\": \"sft_standard_20_retrain\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T14:32:00.808Z\"}, \"grpo_stage2_rasp_20_v7\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T14:06:21.430Z\", \"hypothesis\": \"D030: GRPO v7 — v6 OOM fix. 8-bit AdamW optimizer (bitsandbytes) saves ~50% optimizer memory. max_steps=100 (~756s/step). All other params same as v6: max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True, monkey-patch ref_model.\", \"notes\": \"v7 crashed: RASP 静默死亡（可能 No space left on device 同根因），Standard 报 No space left on device — HF datasets cache 写入根分区导致瞬时磁盘满。双卡空闲 40+ min。v8 修复: HF_DATASETS_CACHE=/root/autodl-tmp/.hf_cache/datasets + HF_HOME=/root/autodl-tmp/.hf_cache。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T14:31:57.799Z\"}, \"grpo_stage2_standard_20_v6\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T12:42:36.011Z\", \"hypothesis\": \"D028: GRPO v6 Standard (negative control) — identical params to RASP v6: max_completion_length=1024, beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True. Direct comparison with RASP v6. If RASP >> Standard, confirms CKA-aware pruning preserves RLVR-recoverable structures.\", \"notes\": \"OOM at step 9/250. Adam._init_group() 分配 1.02 GiB 失败，GPU 0 仅剩 214 MiB。ref_model + train_model 占满 ~95 GiB。PID 521089 僵尸进程仍占 74318 MiB on GPU 1。同 RASP v6 根因。需要 8-bit optimizer 或 ref_model CPU offload。\", \"parent\": \"sft_standard_20_retrain\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T14:02:45.251Z\"}, \"grpo_stage2_rasp_20_v6\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T12:42:34.281Z\", \"hypothesis\": \"D028: GRPO v6 RASP — v5 truncation fix. max_completion_length 512→1024. All other params same: beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True, monkey-patch ref_model. v5 collapsed at step 80 (reward=0, clipped_ratio=97.5%). Expected ~5 min/step, ~21h total.\", \"notes\": \"OOM at step 9/250. Adam._init_group() 分配 130 MiB 失败，GPU 0 仅剩 44 MiB。ref_model + train_model 占满 ~95 GiB。PID 520997 僵尸进程仍占 67430 MiB。max_completion_length=1024, gradient_checkpointing=true, beta=0.01, temp=0.4, lr=1e-6, loss=dapo。需要 8-bit optimizer 或 ref_model CPU offload。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T14:02:43.049Z\"}, \"sft_alpha4_0_westd_retry\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T12:46:36.918Z\", \"hypothesis\": \"D027: α=4.0 pruned model SFT recovery on westd (retry #3). α=4.0 gave highest post-prune accuracy (40%). Fix: CUDA_VISIBLE_DEVICES=1 + --gpu 0 (prevent GPU 0 collision with GraSP) + --save_strategy no (prevent checkpoint serialization crash). Same SFT params: 2 epochs, lr=2e-5, batch=1, grad_accum=8.\", \"metrics\": {\"accuracy_stderr\": 0.049, \"avg_response_length\": 238.56, \"eos_rate\": 0.98, \"mean_token_accuracy_final\": 0.8368, \"n_correct\": 62, \"n_total\": 100, \"post_prune_accuracy\": 0.4, \"post_sft_accuracy_100\": 0.62, \"sft_recovery_gain_pp\": 22, \"train_loss_final\": 0.7393, \"train_loss_last_logged\": 0.6106}, \"notes\": \"SFT training completed (1870/1870 steps, 2 epochs, ~30 min). GSM8K eval (N=100, greedy): 62% accuracy (62/100, stderr=0.049), EOS rate 98%, avg_len 238.56. Post-prune 40% → post-SFT 62% (+22pp recovery). Compared to α=1.0 RASP post-SFT (57%), α=4.0 is +5pp higher, confirming higher α amplifies recovery. Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_ablation/alpha_4.0. Eval JSON: results/eval_alpha_4.0_greedy.json.\", \"parent\": \"alpha_ablation_westd_cal256\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T13:48:13.666Z\"}, \"sft_alpha4_0_westd\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T12:38:41.395Z\", \"hypothesis\": \"D027: α=4.0 pruned model SFT recovery on westd. α=4.0 gave highest post-prune accuracy (40%), testing if SFT recovery further amplifies the advantage. Same SFT params as other α variants (2 epochs, lr=2e-5, batch=1, grad_accum=8).\", \"notes\": \"第一次运行因 save_strategy=\\\"epoch\\\" 中间 checkpoint 序列化占满磁盘而失败。已修改 sft_recovery.py save_strategy=\\\"no\\\"，通过 sft_alpha4_0_westd_retry 重试。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T12:47:41.297Z\"}, \"grpo_stage2_rasp_20_v5\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-15T09:33:29.974Z\", \"hypothesis\": \"D025: GRPO v5 — v4 speed fix. max_completion_length 2048→512 (4x faster generation). All other params same as v4: beta=0.01, temp=0.4, rep_penalty=1.15, format_reward=0.1, gradient_checkpointing=True, monkey-patch ref_model. Expected ~7-10 min/step (vs v4 29min/step).\", \"notes\": \"D027: GRPO v5 RASP 实质性崩溃。Step 40 reward 峰值 0.033，step 80 归零（frac_zero_std=100%）。Grad norm: 2.6→0.01。Clipped ratio 93-97.5%（几乎所有 completion 被截断在 512 tokens）。根因：max_completion_length=512 对 R1 distill 模型不够长，模型无法在 512 token 内完成推理链。Step 89/250, ETA ~5h。建议 kill 并切 v6 (max_completion_length=1024)。\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T12:43:46.085Z\"}, \"reeval_postprune_definitive\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-15T09:46:32.498Z\", \"hypothesis\": \"D023: Definitive re-eval of pruned_standard_20 and pruned_rasp_20 with current eval_gsm8k.py + load_pruned_model. N=100, max_new_tokens=4096, greedy. Validates whether original 1% vs 29% is reproducible with current code.\", \"metrics\": {\"conclusion\": \"Original 29x advantage (29% vs 1%) not reproducible. Actual gap 4pp (31% vs 27% on westb), not statistically significant.\", \"original_claim_rasp\": 0.29, \"original_claim_standard\": 0.01, \"rasp_20_accuracy_westb\": 0.31, \"rasp_20_accuracy_westd\": 0.29, \"rasp_vs_standard_gap_pp\": 4, \"standard_20_accuracy_westb\": 0.27}, \"notes\": \"D023 definitive re-eval complete. westb: RASP 31%, Standard 27% (4pp gap). westd: RASP 29% (2pp delta from westb due to GPU driver 580 vs 595). Original 29% vs 1% claim invalidated — Standard was never 1%, likely eval bug in v4 pipeline. Post-prune gap is ~4pp, not statistically significant at N=100. GRPO Stage 2 is now the sole deterministic experiment for the paper narrative.\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T12:30:41.698Z\"}, \"grpo_stage2_rasp_20_v4\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-15T08:23:49.573Z\", \"hypothesis\": \"D021: GRPO v4 — fixes v2/v3 collapse. Ref_model monkey-patch for beta=0.01 KL penalty, temp 0.4 (from 0.7), repetition_penalty 1.15, format_reward +0.1 for \\\\boxed{}, gradient_checkpointing=True, max_completion_length=2048. If reward>0 at step 10, confirms sampling stabilization.\", \"notes\": \"Killed at step ~1/250 due to 29min/step ETA (120h total). vLLM incompatible with per_layer_intermediate_size. Replaced by v5 with max_completion_length=512.\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T09:32:41.159Z\", \"wandb_run_id\": \"75d1o9wa\"}, \"grpo_stage2_rasp_20_v3\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T07:58:52.482Z\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T09:32:34.875Z\"}, \"grpo_stage2_standard_20_v2\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-15T03:30:01.400Z\", \"hypothesis\": \"D017: GRPO Stage 2 v2 negative control — SFT-warmed Standard-pruned model GRPO recovery with optimized params (max_completion_length=1024, max_samples=1000). Post-SFT: 64% greedy accuracy, EOS 99%, avg_len 176 tokens. Expected: GRPO improvement smaller than RASP counterpart.\", \"notes\": \"D019: GRPO Stage 2 v2 Standard (negative control) — EXIT_CODE=129 (SIGHUP) at step 33/250 (~4h05m, retry_count=1). Confirmed grad_norm=0 collapse: sampling mode (temp=0.7) produces degenerate output (\\\"#### 7248\\\" repeated), reward=0.00, 0 gradient. Despite SFT restoring 64% greedy accuracy and 99% EOS, GRPO sampling destabilizes the pruned model into repetitive loops. Same root cause as RASP counterpart — GRPO method failure, not model-specific.\", \"parent\": \"sft_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T08:15:31.861Z\", \"wandb_run_id\": \"iinlgfqk\"}, \"grpo_stage2_rasp_20_v2\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-15T03:30:00.666Z\", \"hypothesis\": \"D017: GRPO Stage 2 v2 — SFT-warmed RASP-pruned model RLVR recovery with optimized params (max_completion_length=1024, max_samples=1000). Post-SFT: 57% greedy accuracy, EOS 99%, avg_len 180 tokens. Reduced completion length justified by SFT restoring EOS. If GRPO pushes RASP significantly above Standard, confirms CKA-aware pruning preserves RLVR-recoverable structures.\", \"notes\": \"D019: GRPO Stage 2 v2 RASP — killed at step 35/250 (~4h17m). Confirmed grad_norm=0 collapse: sampling mode (temp=0.7) produces degenerate repetitive loops (e.g. \\\"$708033600000\\\" repeated 20+ steps), 0 reward, 0 gradient. Despite SFT restoring 57% greedy accuracy and 99% EOS rate, GRPO sampling destabilizes the pruned model. Same root cause as Standard counterpart. This is a GRPO method failure, not a RASP vs Standard comparison. wandb: e16rbclf.\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T08:15:30.925Z\", \"wandb_run_id\": \"e16rbclf\"}, \"grpo_stage2_standard_20\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-15T01:11:12.341Z\", \"hypothesis\": \"GRPO Stage 2 negative control: SFT-warmed Standard-pruned model GRPO recovery. Post-SFT accuracy 64% (greedy eval N=100), EOS restored. Expected: GRPO improvement smaller than RASP counterpart, confirming standard pruning removes structures less amenable to RLVR recovery.\", \"notes\": \"D017: Killed for parameter optimization restart. max_completion_length 4096→1024 (SFT后EOS 99%, avg 176 tokens, 4096浪费). max_samples 2000→1000. Superseded by grpo_stage2_standard_20_v2.\", \"parent\": \"sft_standard_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T03:33:30.780Z\"}, \"grpo_stage2_rasp_20\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-15T01:11:10.490Z\", \"hypothesis\": \"GRPO Stage 2 (plan_003): SFT-warmed RASP-pruned model recovers reasoning via RLVR. Post-SFT accuracy 57% (greedy eval N=100), EOS restored. If GRPO pushes RASP significantly above Standard, confirms CKA-aware pruning preserves RLVR-recoverable structures.\", \"notes\": \"D017: Killed for parameter optimization restart. max_completion_length 4096→1024 (SFT后EOS 99%, avg 176 tokens, 4096浪费). max_samples 2000→1000. Superseded by grpo_stage2_rasp_20_v2.\", \"parent\": \"sft_rasp_20\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T03:33:11.856Z\"}, \"sft_standard_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-14T23:37:34.863Z\", \"hypothesis\": \"D013 Stage 1: SFT warmup on Standard-pruned model (20%, 1% GSM8K) as negative control. Expected: SFT partially recovers format but reasoning remains limited.\", \"metrics\": {\"eos_rate_greedy_100\": 0.99, \"greedy_accuracy_100\": 0.64, \"greedy_avg_len\": 176.31, \"greedy_correct\": 64, \"greedy_max_len\": 4096, \"greedy_min_len\": 43, \"greedy_total\": 100, \"sampling_eos_rate_5\": 1, \"token_accuracy\": 0.83, \"total_steps\": 1870, \"train_loss_final\": 0.64, \"train_loss_initial\": 1.7, \"train_time_min\": 37}, \"notes\": \"SFT warmup SUCCESS (负对照). EOS恢复100% (3/3测试). Loss 1.70→0.64, token_accuracy 83%. 但推理准确率有限(2/3, 12+15算成41), 说明standard pruning破坏了关键推理结构, SFT只恢复了格式+EOS, 无法完全恢复数学推理. 平均生成49 tokens, 无重复循环. 训练37min, 1870 steps. Greedy eval N=100: 64% accuracy, avg_len=176.31, eos_rate=99%. N=100 sampling eval was killed (OOM by concurrent GRPO). Eval JSON: /root/recovery_aware_struct_prune/results/eval_sft_standard_20_combined.json. Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_standard_20/\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T02:49:41.141Z\"}, \"sft_rasp_20\": {\"conclusion\": \"success\", \"created_at\": \"2026-05-14T23:37:33.162Z\", \"hypothesis\": \"D013 Stage 1: SFT warmup on RASP-pruned model (20%, 29% GSM8K) to restore EOS generation ability before GRPO Stage 2.\", \"metrics\": {\"eos_rate_greedy_100\": 0.99, \"greedy_accuracy_100\": 0.57, \"greedy_avg_len\": 179.83, \"greedy_correct\": 57, \"greedy_max_len\": 4096, \"greedy_min_len\": 59, \"greedy_total\": 100, \"sampling_eos_rate_5\": 1, \"token_accuracy\": 0.83, \"total_steps\": 1870, \"train_loss_final\": 0.64, \"train_loss_initial\": 1.86, \"train_time_min\": 37}, \"notes\": \"SFT warmup SUCCESS. EOS恢复100% (5/5测试). Loss 1.86→0.64, token_accuracy 83%. 平均生成77 tokens, 无重复循环, 遵循GSM8K格式. 训练时间37min, 1870 steps (2 epochs). Greedy eval N=100: 57% accuracy, avg_len=179.83, eos_rate=99%. N=100 sampling eval was killed (OOM by concurrent GRPO). Eval JSON: /root/recovery_aware_struct_prune/results/eval_sft_rasp_20_combined.json. Checkpoint: /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20/\", \"status\": \"DONE\", \"updated_at\": \"2026-05-15T02:49:39.222Z\"}, \"grpo_rasp_20_4096\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-14T22:43:12.378Z\", \"hypothesis\": \"D010: RASP-pruned model (20% sparsity, post-prune 29% GSM8K) GRPO recovery with max_completion_length=4096 (fix D009 truncation). Core MVP experiment — if recovery succeeds, RASP structure selection enables RLVR recovery that standard pruning cannot.\", \"notes\": \"D013: Killed at step 10/500. clipped_ratio=1.0, grad_norm=0, mean_terminated_length=0. RASP model (29% greedy accuracy) completely degrades in sampling mode (temp=0.7): repetitive loops and digit sequences, never produces EOS. 4096 tokens not the issue — pruning destroys sampling-mode generation quality. Same root cause as Standard. Switched to SFT warmup → GRPO two-stage recovery (D013). wandb: ccx0jr0z.\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T23:54:07.328Z\"}, \"grpo_standard_20_4096\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-14T22:19:37.356Z\", \"hypothesis\": \"D010: Standard-pruned model (20% sparsity, post-prune 1% GSM8K) GRPO recovery with max_completion_length=4096 (fix D009 truncation). Negative control — expected to fail recovery due to non-optimal structure selection, confirming RASP advantage.\", \"notes\": \"D011: Killed at step 10/500. 10步零梯度确认不可恢复——clipped_ratio=0.9938, grad_norm=0, loss≈0, reward=0.00625. 根因不是token长度不足,而是模型能力丧失(1% accuracy → 输出无意义重复数字,无法产出EOS). 即使8192/16384也无济于事. 作为负对照证据保留10步日志+wandb(ou02s4k4). Checkpoint: /root/autodl-tmp/recovered_standard_20_4096/\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T23:17:13.491Z\"}, \"grpo_standard_20_fast\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-14T17:38:55.838Z\", \"hypothesis\": \"Standard-pruned model (20% sparsity, post-prune 1% GSM8K) expected to fail GRPO recovery (RewardDesertCallback triggers). This is the negative control — confirms RASP's structure selection enables recovery that standard pruning cannot.\", \"notes\": \"[D009 INCONCLUSIVE — truncation artifact, not true negative] Training completed 500/500 steps (3h31m). Zero effective learning — reward stayed ~0.006-0.019 throughout, grad_norm=0, loss=0. All completions clipped at max_length=1024, 0 natural terminations. Root cause: max_completion_length=1024 too short for R1 CoT reasoning (needs 2000-4000 tokens). GRPO never received gradient signal. Hypothesis untested. wandb: ou02s4k4. Checkpoint: /root/autodl-tmp/recovered_standard_20/ (deleted, no value). Superseded by D010 grpo_standard_20_4096.\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T22:18:03.971Z\"}, \"grpo_rasp_20_fast\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-14T17:38:53.540Z\", \"hypothesis\": \"RASP-pruned model (20% sparsity, post-prune 29% GSM8K) recovers under GRPO RLVR with fast config (1024 tokens, 1 epoch, 2000 samples). Expected: reward > 0, meaningful recovery within 500 steps.\", \"notes\": \"[D009 INCONCLUSIVE — truncation artifact, not true negative] Training completed 500/500 steps (3h32m). Zero effective learning — reward stayed ~0.006-0.019 throughout, grad_norm=0, loss=0. All completions clipped at max_length=1024, 0 natural terminations. Root cause: max_completion_length=1024 too short for R1 CoT reasoning (needs 2000-4000 tokens). GRPO never received gradient signal. Hypothesis untested. wandb: sz9264sx. Checkpoint: /root/autodl-tmp/recovered_rasp_20/ (deleted, no value). Superseded by D010 grpo_rasp_20_4096.\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T22:18:01.563Z\"}, \"grpo_standard_20\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-14T17:11:33.478Z\", \"hypothesis\": \"Baseline: Standard importance-only pruned model (20% sparsity, post-prune 1% GSM8K) recovery via GRPO RLVR. Expected to recover less than RASP counterpart due to non-optimal structure selection.\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T17:37:57.677Z\"}, \"grpo_rasp_20\": {\"conclusion\": \"killed\", \"created_at\": \"2026-05-14T17:08:34.784Z\", \"hypothesis\": \"RASP-pruned model (20% sparsity, post-prune 29% GSM8K) recovers better under GRPO RLVR than standard-pruned model (20% sparsity, post-prune 1% GSM8K). Both have identical total MLP params (395,232) — difference is purely from distribution strategy (Scenario B).\", \"parent\": \"mvp_rasp_pipeline_v4\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T17:37:57.217Z\"}, \"mvp_rasp_pipeline_v3\": {\"conclusion\": \"negative\", \"created_at\": \"2026-05-14T14:00:25.837Z\", \"hypothesis\": \"CKA functional overlap F(h) predicts structured pruning recoverability under RLVR. RASP scoring S(h)=I(h)×(1-F(h))^α selects structures whose removal is more recoverable via GRPO RLVR than standard importance-only pruning. MVP: Spearman ρ(F(h), recoverability) ≥ 0.4 on DeepSeek-R1-Distill-Qwen-7B @ 35% sparsity. V3: Fixed per-layer capacity floor (MLP ≥40% per layer) to prevent early layer collapse.\", \"notes\": \"v3 fix: min_keep_mlp changed from 4 to max(4, int(n_mlp_groups*0.4))=12, ensuring ≥40% MLP capacity per layer. Actual sparsity: Standard=33.02%, RASP=33.21%. MLP range both [8128,18944]. GSM8K@100 results: Standard=0.0% (0/100), RASP=1.0% (1/100). v2 had 0.15% with min_keep_mlp=4. The capacity floor preserved more MLP width but did not rescue reasoning ability. Model outputs remain degenerate (repeated digits, empty strings, repetition loops). 35% structured sparsity fundamentally destroys too much model capacity for this architecture. Next steps: (1) try 20-25% sparsity, (2) add post-prune recovery fine-tuning (the actual RASP hypothesis), or (3) semi-structured pruning.\", \"parent\": \"mvp_rasp_pipeline_v2\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T14:40:41.424Z\"}, \"mvp_rasp_pipeline_v2\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-14T06:08:01.844Z\", \"hypothesis\": \"CKA functional overlap F(h) predicts structured pruning recoverability under RLVR. RASP scoring S(h)=I(h)×(1-F(h))^α selects structures whose removal is more recoverable via GRPO RLVR than standard importance-only pruning. MVP: Spearman ρ(F(h), recoverability) ≥ 0.4 on DeepSeek-R1-Distill-Qwen-7B @ 35% sparsity. V2: GQA group granularity + MLP-level correlation.\", \"notes\": \"根因：prune.py min_keep_mlp=4，每层 28 MLP groups 保留仅 4 组(14.3%)。全局贪心排序导致 early layers (0-6) 被集中剪至 14.3% capacity，摧毁初始表征 → 模型崩溃至 0.15% accuracy。RASP scoring 逻辑本身正常（两模型选了不同结构），但都被剪崩了。GRPO 在退化模型上 loss=0/grad_norm=0，无学习信号。\", \"parent\": \"mvp_rasp_pipeline\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T14:00:06.035Z\"}, \"mvp_rasp_pipeline\": {\"conclusion\": \"failed\", \"created_at\": \"2026-05-14T04:10:10.348Z\", \"hypothesis\": \"CKA functional overlap F(h) 预测结构化剪枝后 RLVR recoverability：高 overlap heads 被剪后 RLVR 更容易恢复其功能（通过调整相似 retained heads）。MVP 验证 Spearman ρ(F(h), recoverability) ≥ 0.4。\", \"status\": \"DONE\", \"updated_at\": \"2026-05-14T05:26:15.414Z\"}}, \"count\": 227, \"total\": 227, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 2.3857}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 15 · 2026-05-19T18:24:38.114Z_

<details><summary>↩ Tool result · `toolu_01846SSPHugcQcfYxSqRXVnP`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/ROADMAP.md\", \"content\": \"# recovery_aware_struct_prune — Research Dashboard\\n\\n> 最后更新: 2026-05-19 17:14 UTC | 更新原因: D078 gradient flow mechanism 升级 + 优先级重排 + 实验进展同步\\n\\n## 核心方向\\nPruning criterion determines post-RLVR recovery capacity AND capability breadth. CKA-only >> importance-based. 详见 paper_framing.md.\\n\\n## 当前阶段: D075 Full Expansion Push (EMNLP Main ≥ 4.0)\\n\\n### 已完成核心数据\\n- **C2 Recovery Gradient (7B)**: ✅ 4-method fair v5. CKA-only 0.354 >> Random 0.19 >> Standard 0.081 > RASP 0.061\\n- **E2 Extended 300步**: ✅ CKA-only 5.5x Standard. Collapse permanent.\\n- **E3 CKA Heatmap**: ✅ Mechanism confirmed (static evidence).\\n- **1.5B Cross-Scale GSM8K**: ✅ CKA-only 35.48% >> RASP 26.16% > Standard 22.29%\\n- **MATH-500 @2048**: ✅ Full 3×2 table. All |GRPO-SFT| < 2pp.\\n- **Unstructured GRPO**: ✅ 87.64%. Collapse = structural damage.\\n- **GSM8K 7B GRPO 完整排名**: ✅ CKA-only 64.37% > RASP 60.88% > Standard 59.44%\\n- **HumanEval 7B @2048 完整矩阵**: ✅ CKA-only 20.12% >> Standard 13.41% > RASP 10.37%\\n- **Gradient Flow v3 三阶梯** (D078): ✅ CKA-only 2.89x > RASP 1.28x > Standard 1.0x (55-56/56 层显著, 200 samples, Wilcoxon). **Mechanism 从 supplementary 升到 main story**。\\n- **MBPP Dense baseline**: ✅ pass@1=53.48% (200/374)\\n\\n### 正在运行\\n| GPU | 实验 | 状态 | 意义 |\\n|-----|------|------|------|\\n| westb:0 | eval_humaneval_grpo_standard_20_1p5b_2048 | RUNNING | 1.5B cross-scale |\\n| westb:1 | eval_gsm8k_grpo_cka_only_20_seed123 | RUNNING | Multi-seed validation |\\n| westd:0 | grpo_shortgpt_20 | RUNNING | ShortGPT baseline (审稿人必问) |\\n| westd:1 | eval_humaneval_sft_rasp_20_1p5b_2048 | RUNNING | 1.5B HumanEval |\\n| westd:2 | eval_mbpp_grpo_standard_20 | RUNNING | MBPP matrix |\\n| westd:3 | eval_gsm8k_sft_shortgpt_20 | RUNNING | ShortGPT eval |\\n\\n### 近期任务（按优先级排序）\\n- [ ] P0: seed123 GSM8K 结果 → multi-seed C2 稳健性\\n- [ ] P0: ShortGPT 全 pipeline (SFT✅→GSM8K eval🔄→GRPO🔄→GRPO eval) → baseline 对比\\n- [ ] P0: MBPP 矩阵补全 (Dense✅, GRPO CKA🔄, GRPO Standard🔄, 待跑: SFT各方法 + RASP GRPO)\\n- [ ] P1: Paper framing 更新 — gradient flow 三阶梯纳入 C2 mechanism section (D078)\\n- [ ] P1: RCI 预测指标 — gradient magnitude → recovery capacity 形式化 (如 rank correlation)\\n- [ ] P2: 跨架构 Qwen2.5-Math-7B — CKA-only vs Standard (可 defer 到 camera-ready)\\n- [ ] P2: Pruning ratio sweep 10%/15% — 补完曲线\\n- [x] Gradient flow v3 RASP vs Standard Wilcoxon ✅\\n\\n### Claim 强度升级 (D078 决策)\\nMechanism analysis 从 \\\"E3 heatmap 辅助证据\\\" 升级为 \\\"CKA heatmap + gradient flow 双重机制证据\\\":\\n1. Heatmap (静态): diversity preservation → CKA-only 最低 Dense-CKA (0.62 vs 0.88-0.92)\\n2. Gradient flow (动态): diversity → 2.89x 更强梯度信号 (55/56 层显著)\\n3. 合在一起: diversity preservation → stronger training signals → superior recovery\\n⚠️ Framing: \\\"consistent with\\\" 而非 \\\"enables\\\" (correlational evidence)\\n\\n## GPU 预算\\n- 6 GPU × 5 days = 720 GPU-hours total\\n- 已用 ~200h, 剩余 ~520h\\n- 瓶颈: ShortGPT GRPO 训练 (~12h) + 各种 eval\\n\\n## 投稿目标\\n- EMNLP 2026 Main (ARR May 25) — **~5 天**\\n- 目标评分: ≥ 4.0 (Conference)\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 | 关联实验 |\\n|----|------|------|----------|\\n| D078 | 2026-05-19 | D078: Mechanism analysis 升级——gradient flow 三阶梯纳入 C | gradient_flow_v3, gradient_flow_analysis |\\n| D077 | 2026-05-19 | D077: Capability breadth claim scoped to 7B; 1.5B  | eval_humaneval_sft_cka_only_20_1p5b_2048, eval_humaneval_grpo_cka_only_20_1p5b_2048 |\\n| D076 | 2026-05-19 | D075: C1 decoupling 从 task-dependent 升级为 universal | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20 |\\n| D075 | 2026-05-19 | D075: Full expansion plan with user backing — all  | — |\\n| D074 | 2026-05-19 | D074: HumanEval overlap analysis reveals GRPO capa | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20_2048, eval_humaneval_grpo_standard_20_fair_2048_v3, eval_humaneval_grpo_rasp_20_fair_2048 |\\n| D073 | 2026-05-19 | D073: C1 definitively simplified — GRPO delta = 0. | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20_2048, eval_humaneval_grpo_rasp_20_fair_2048 |\\n| D072 | 2026-05-19 | D072: D071 叙事被 SFT CKA-only HumanEval v2 interim ~ | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20_2048, eval_humaneval_grpo_rasp_20_fair_2048, eval_humaneval_grpo_standard_20_fair_2048_v3 |\\n| D071 | 2026-05-19 | C1 reframing: GRPO-accuracy interaction is task-de | eval_humaneval_sft_cka_only_20, eval_humaneval_grpo_cka_only_20, eval_humaneval_sft_standard_20, eval_humaneval_sft_rasp_20 |\\n| D070 | 2026-05-19 | D070: C1 reframing — GRPO-accuracy interaction is  | eval_humaneval_sft_cka_only_20_2048, eval_humaneval_grpo_cka_only_20_2048 |\\n| D069 | 2026-05-19 | D069: C2 statistical evidence restructure — 1.5B a | bootstrap_ci_v2, grpo_cka_only_20, grpo_rasp_20_fair |\\n\\n\\n\", \"total_chars\": 4565, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "6c83241f-74b2-42c4-9310-8d073b00acdf",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/ROADMAP.md\\\", \\\"content\\\": \\\"# recovery_aware_struct_prune — Research Dashboard\\\\n\\\\n> 最后更新: 2026-05-19 17:14 UTC | 更新原因: D078 gradient flow mechanism 升级 + 优先级重排 + 实验进展同步\\\\n\\\\n## 核心方向\\\\nPruning criterion determines post-RLVR recovery capacity AND capability breadth. CKA-only >> importance-based. 详见 paper_framing.md.\\\\n\\\\n## 当前阶段: D075 Full Expansion Push (EMNLP Main ≥ 4.0)\\\\n\\\\n### 已完成核心数据\\\\n- **C2 Recovery Gradient (7B)**: ✅ 4-method fair v5. CKA-only 0.354 >> Random 0.19 >> Standard 0.081 > RASP 0.061\\\\n- **E2 Extended 300步**: ✅ CKA-only 5.5x Standard. Collapse permanent.\\\\n- **E3 CKA Heatmap**: ✅ Mechanism confirmed (static evidence).\\\\n- **1.5B Cross-Scale GSM8K**: ✅ CKA-only 35.48% >> RASP 26.16% > Standard 22.29%\\\\n- **MATH-500 @2048**: ✅ Full 3×2 table. All |GRPO-SFT| < 2pp.\\\\n- **Unstructured GRPO**: ✅ 87.64%. Collapse = structural damage.\\\\n- **GSM8K 7B GRPO 完整排名**: ✅ CKA-only 64.37% > RASP 60.88% > Standard 59.44%\\\\n- **HumanEval 7B @2048 完整矩阵**: ✅ CKA-only 20.12% >> Standard 13.41% > RASP 10.37%\\\\n- **Gradient Flow v3 三阶梯** (D078): ✅ CKA-only 2.89x > RASP 1.28x > Standard 1.0x (55-56/56 层显著, 200 samples, Wilcoxon). **Mechanism 从 supplementary 升到 main story**。\\\\n- **MBPP Dense baseline**: ✅ pass@1=53.48% (200/374)\\\\n\\\\n### 正在运行\\\\n| GPU | 实验 | 状态 | 意义 |\\\\n|-----|------|------|------|\\\\n| westb:0 | eval_humaneval_grpo_standard_20_1p5b_2048 | RUNNING | 1.5B cross-scale |\\\\n| westb:1 | eval_gsm8k_grpo_cka_only_20_seed123 | RUNNING | Multi-seed validation |\\\\n| westd:0 | grpo_shortgpt_20 | RUNNING | ShortGPT baseline (审稿人必问) |\\\\n| westd:1 | eval_humaneval_sft_rasp_20_1p5b_2048 | RUNNING | 1.5B HumanEval |\\\\n| westd:2 | eval_mbpp_grpo_standard_20 | RUNNING | MBPP matrix |\\\\n| westd:3 | eval_gsm8k_sft_shortgpt_20 | RUNNING | ShortGPT eval |\\\\n\\\\n### 近期任务（按优先级排序）\\\\n- [ ] P0: seed123 GSM8K 结果 → multi-seed C2 稳健性\\\\n- [ ] P0: ShortGPT 全 pipeline (SFT✅→GSM8K eval🔄→GRPO🔄→GRPO eval) → baseline 对比\\\\n- [ ] P0: MBPP 矩阵补全 (Dense✅, GRPO CKA🔄, GRPO Standard🔄, 待跑: SFT各方法 + RASP GRPO)\\\\n- [ ] P1: Paper framing 更新 — gradient flow 三阶梯纳入 C2 mechanism section (D078)\\\\n- [ ] P1: RCI 预测指标 — gradient magnitude → recovery capacity 形式化 (如 rank correlation)\\\\n- [ ] P2: 跨架构 Qwen2.5-Math-7B — CKA-only vs Standard (可 defer 到 camera-ready)\\\\n- [ ] P2: Pruning ratio sweep 10%/15% — 补完曲线\\\\n- [x] Gradient flow v3 RASP vs Standard Wilcoxon ✅\\\\n\\\\n### Claim 强度升级 (D078 决策)\\\\nMechanism analysis 从 \\\\\\\"E3 heatmap 辅助证据\\\\\\\" 升级为 \\\\\\\"CKA heatmap + gradient flow 双重机制证据\\\\\\\":\\\\n1. Heatmap (静态): diversity preservation → CKA-only 最低 Dense-CKA (0.62 vs 0.88-0.92)\\\\n2. Gradient flow (动态): diversity → 2.89x 更强梯度信号 (55/56 层显著)\\\\n3. 合在一起: diversity preservation → stronger training signals → superior recovery\\\\n⚠️ Framing: \\\\\\\"consistent with\\\\\\\" 而非 \\\\\\\"enables\\\\\\\" (correlational evidence)\\\\n\\\\n## GPU 预算\\\\n- 6 GPU × 5 days = 720 GPU-hours total\\\\n- 已用 ~200h, 剩余 ~520h\\\\n- 瓶颈: ShortGPT GRPO 训练 (~12h) + 各种 eval\\\\n\\\\n## 投稿目标\\\\n- EMNLP 2026 Main (ARR May 25) — **~5 天**\\\\n- 目标评分: ≥ 4.0 (Conference)\\\\n\\\\n## 关键决策日志\\\\n\\\\n| ID | 日期 | 摘要 | 关联实验 |\\\\n|----|------|------|----------|\\\\n| D078 | 2026-05-19 | D078: Mechanism analysis 升级——gradient flow 三阶梯纳入 C | gradient_flow_v3, gradient_flow_analysis |\\\\n| D077 | 2026-05-19 | D077: Capability breadth claim scoped to 7B; 1.5B  | eval_humaneval_sft_cka_only_20_1p5b_2048, eval_humaneval_grpo_cka_only_20_1p5b_2048 |\\\\n| D076 | 2026-05-19 | D075: C1 decoupling 从 task-dependent 升级为 universal | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20 |\\\\n| D075 | 2026-05-19 | D075: Full expansion plan with user backing — all  | — |\\\\n| D074 | 2026-05-19 | D074: HumanEval overlap analysis reveals GRPO capa | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20_2048, eval_humaneval_grpo_standard_20_fair_2048_v3, eval_humaneval_grpo_rasp_20_fair_2048 |\\\\n| D073 | 2026-05-19 | D073: C1 definitively simplified — GRPO delta = 0. | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20_2048, eval_humaneval_grpo_rasp_20_fair_2048 |\\\\n| D072 | 2026-05-19 | D072: D071 叙事被 SFT CKA-only HumanEval v2 interim ~ | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20_2048, eval_humaneval_grpo_rasp_20_fair_2048, eval_humaneval_grpo_standard_20_fair_2048_v3 |\\\\n| D071 | 2026-05-19 | C1 reframing: GRPO-accuracy interaction is task-de | eval_humaneval_sft_cka_only_20, eval_humaneval_grpo_cka_only_20, eval_humaneval_sft_standard_20, eval_humaneval_sft_rasp_20 |\\\\n| D070 | 2026-05-19 | D070: C1 reframing — GRPO-accuracy interaction is  | eval_humaneval_sft_cka_only_20_2048, eval_humaneval_grpo_cka_only_20_2048 |\\\\n| D069 | 2026-05-19 | D069: C2 statistical evidence restructure — 1.5B a | bootstrap_ci_v2, grpo_cka_only_20, grpo_rasp_20_fair |\\\\n\\\\n\\\\n\\\", \\\"total_chars\\\": 4565, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_17/projects/recovery_aware_struct_prune/ROADMAP.md\", \"content\": \"# recovery_aware_struct_prune — Research Dashboard\\n\\n> 最后更新: 2026-05-19 17:14 UTC | 更新原因: D078 gradient flow mechanism 升级 + 优先级重排 + 实验进展同步\\n\\n## 核心方向\\nPruning criterion determines post-RLVR recovery capacity AND capability breadth. CKA-only >> importance-based. 详见 paper_framing.md.\\n\\n## 当前阶段: D075 Full Expansion Push (EMNLP Main ≥ 4.0)\\n\\n### 已完成核心数据\\n- **C2 Recovery Gradient (7B)**: ✅ 4-method fair v5. CKA-only 0.354 >> Random 0.19 >> Standard 0.081 > RASP 0.061\\n- **E2 Extended 300步**: ✅ CKA-only 5.5x Standard. Collapse permanent.\\n- **E3 CKA Heatmap**: ✅ Mechanism confirmed (static evidence).\\n- **1.5B Cross-Scale GSM8K**: ✅ CKA-only 35.48% >> RASP 26.16% > Standard 22.29%\\n- **MATH-500 @2048**: ✅ Full 3×2 table. All |GRPO-SFT| < 2pp.\\n- **Unstructured GRPO**: ✅ 87.64%. Collapse = structural damage.\\n- **GSM8K 7B GRPO 完整排名**: ✅ CKA-only 64.37% > RASP 60.88% > Standard 59.44%\\n- **HumanEval 7B @2048 完整矩阵**: ✅ CKA-only 20.12% >> Standard 13.41% > RASP 10.37%\\n- **Gradient Flow v3 三阶梯** (D078): ✅ CKA-only 2.89x > RASP 1.28x > Standard 1.0x (55-56/56 层显著, 200 samples, Wilcoxon). **Mechanism 从 supplementary 升到 main story**。\\n- **MBPP Dense baseline**: ✅ pass@1=53.48% (200/374)\\n\\n### 正在运行\\n| GPU | 实验 | 状态 | 意义 |\\n|-----|------|------|------|\\n| westb:0 | eval_humaneval_grpo_standard_20_1p5b_2048 | RUNNING | 1.5B cross-scale |\\n| westb:1 | eval_gsm8k_grpo_cka_only_20_seed123 | RUNNING | Multi-seed validation |\\n| westd:0 | grpo_shortgpt_20 | RUNNING | ShortGPT baseline (审稿人必问) |\\n| westd:1 | eval_humaneval_sft_rasp_20_1p5b_2048 | RUNNING | 1.5B HumanEval |\\n| westd:2 | eval_mbpp_grpo_standard_20 | RUNNING | MBPP matrix |\\n| westd:3 | eval_gsm8k_sft_shortgpt_20 | RUNNING | ShortGPT eval |\\n\\n### 近期任务（按优先级排序）\\n- [ ] P0: seed123 GSM8K 结果 → multi-seed C2 稳健性\\n- [ ] P0: ShortGPT 全 pipeline (SFT✅→GSM8K eval🔄→GRPO🔄→GRPO eval) → baseline 对比\\n- [ ] P0: MBPP 矩阵补全 (Dense✅, GRPO CKA🔄, GRPO Standard🔄, 待跑: SFT各方法 + RASP GRPO)\\n- [ ] P1: Paper framing 更新 — gradient flow 三阶梯纳入 C2 mechanism section (D078)\\n- [ ] P1: RCI 预测指标 — gradient magnitude → recovery capacity 形式化 (如 rank correlation)\\n- [ ] P2: 跨架构 Qwen2.5-Math-7B — CKA-only vs Standard (可 defer 到 camera-ready)\\n- [ ] P2: Pruning ratio sweep 10%/15% — 补完曲线\\n- [x] Gradient flow v3 RASP vs Standard Wilcoxon ✅\\n\\n### Claim 强度升级 (D078 决策)\\nMechanism analysis 从 \\\"E3 heatmap 辅助证据\\\" 升级为 \\\"CKA heatmap + gradient flow 双重机制证据\\\":\\n1. Heatmap (静态): diversity preservation → CKA-only 最低 Dense-CKA (0.62 vs 0.88-0.92)\\n2. Gradient flow (动态): diversity → 2.89x 更强梯度信号 (55/56 层显著)\\n3. 合在一起: diversity preservation → stronger training signals → superior recovery\\n⚠️ Framing: \\\"consistent with\\\" 而非 \\\"enables\\\" (correlational evidence)\\n\\n## GPU 预算\\n- 6 GPU × 5 days = 720 GPU-hours total\\n- 已用 ~200h, 剩余 ~520h\\n- 瓶颈: ShortGPT GRPO 训练 (~12h) + 各种 eval\\n\\n## 投稿目标\\n- EMNLP 2026 Main (ARR May 25) — **~5 天**\\n- 目标评分: ≥ 4.0 (Conference)\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 | 关联实验 |\\n|----|------|------|----------|\\n| D078 | 2026-05-19 | D078: Mechanism analysis 升级——gradient flow 三阶梯纳入 C | gradient_flow_v3, gradient_flow_analysis |\\n| D077 | 2026-05-19 | D077: Capability breadth claim scoped to 7B; 1.5B  | eval_humaneval_sft_cka_only_20_1p5b_2048, eval_humaneval_grpo_cka_only_20_1p5b_2048 |\\n| D076 | 2026-05-19 | D075: C1 decoupling 从 task-dependent 升级为 universal | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20 |\\n| D075 | 2026-05-19 | D075: Full expansion plan with user backing — all  | — |\\n| D074 | 2026-05-19 | D074: HumanEval overlap analysis reveals GRPO capa | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20_2048, eval_humaneval_grpo_standard_20_fair_2048_v3, eval_humaneval_grpo_rasp_20_fair_2048 |\\n| D073 | 2026-05-19 | D073: C1 definitively simplified — GRPO delta = 0. | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20_2048, eval_humaneval_grpo_rasp_20_fair_2048 |\\n| D072 | 2026-05-19 | D072: D071 叙事被 SFT CKA-only HumanEval v2 interim ~ | eval_humaneval_sft_cka_only_20_2048_v2, eval_humaneval_grpo_cka_only_20_2048, eval_humaneval_grpo_rasp_20_fair_2048, eval_humaneval_grpo_standard_20_fair_2048_v3 |\\n| D071 | 2026-05-19 | C1 reframing: GRPO-accuracy interaction is task-de | eval_humaneval_sft_cka_only_20, eval_humaneval_grpo_cka_only_20, eval_humaneval_sft_standard_20, eval_humaneval_sft_rasp_20 |\\n| D070 | 2026-05-19 | D070: C1 reframing — GRPO-accuracy interaction is  | eval_humaneval_sft_cka_only_20_2048, eval_humaneval_grpo_cka_only_20_2048 |\\n| D069 | 2026-05-19 | D069: C2 statistical evidence restructure — 1.5B a | bootstrap_ci_v2, grpo_cka_only_20, grpo_rasp_20_fair |\\n\\n\\n\", \"total_chars\": 4565, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
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
Let me process the information:

1. **Checkpoints on westb**: I have a full list. Let me organize them.

2. **Source files**: `eval_mbpp.py` exists in `/root/recovery_aware_struct_prune/src/`

3. **Registry**: Too large, need to query it more specifically.

4. **ROADMAP**: Shows current running experiments and priorities.

Key observations from ROADMAP:
- westb:0 is running `eval_humaneval_grpo_standard_20_1p5b_2048` (not what the user said - user said `eval_humaneval_sft_rasp_20_1p5b_2048`)


- westb:1 shows a running experiment in the ROADMAP, but the user says it's idle, so either the ROADMAP is outdated or the job finished. I need to check the actual GPU status and query the registry more specifically for 1.5B experiments and plan_014.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "7137c28f-d582-4e37-8ab5-1397b0a661fb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W2fWpY4xFzxgEYt76VSEEw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5334,
      "cache_read_input_tokens": 25217,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5334
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

ROADMAP shows westb:1 was running `eval_gsm8k_grpo_cka_only_20_seed123`. Let me verify actual GPU status and query the registry for 1.5B experiments.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "01dfe041-9546-4be1-80f9-f2662e0b0880",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W2fWpY4xFzxgEYt76VSEEw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5334,
      "cache_read_input_tokens": 25217,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5334
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01MCKQDqCLidF19un6nqCBr8`</summary>

```json
{
  "server": "westb-23072",
  "command": "nvidia-smi --query-compute-apps=pid,gpu_uuid,used_memory,name --format=csv,noheader",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "946ba77b-90e6-4cc9-aa47-ec58cdea9786",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W2fWpY4xFzxgEYt76VSEEw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5334,
      "cache_read_input_tokens": 25217,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5334
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

_source line 19 · 2026-05-19T18:24:53.937Z_

<details><summary>↩ Tool result · `toolu_01MCKQDqCLidF19un6nqCBr8`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"909411, GPU-549a7198-85c3-248c-9f75-5b8d5ff146f4, 4314 MiB, python\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.84}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "36cb0a14-e406-48c3-8431-df535c88e2fe",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"909411, GPU-549a7198-85c3-248c-9f75-5b8d5ff146f4, 4314 MiB, python\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.84}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"909411, GPU-549a7198-85c3-248c-9f75-5b8d5ff146f4, 4314 MiB, python\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.84}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 20_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_017642qBoME5U288sy3TCScG`</summary>

```json
{
  "server": "westb-23072",
  "command": "ls /root/autodl-tmp/recovery_aware_struct_prune/results/",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "4a106f2a-9885-43c0-a66a-86146a984067",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W2fWpY4xFzxgEYt76VSEEw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5334,
      "cache_read_input_tokens": 25217,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5334
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

_source line 21 · 2026-05-19T18:24:55.026Z_

<details><summary>↩ Tool result · `toolu_017642qBoME5U288sy3TCScG`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"ablation_log.txt\\nbinary_outcomes_westb.json\\ncka_heatmap_cka_only.json\\ncka_heatmap_random.json\\ncka_heatmap_rasp.json\\ncka_heatmap_standard.json\\ncka_reliability_ablation.json\\ne3_cka_heatmap.pdf\\neval_cka_only_20_n200.json\\neval_gradient_postsft.json\\neval_gradient_sft.log\\neval_grpo_rasp_25_n1319.json\\neval_grpo_rasp_v9_step10.json\\neval_gsm8k_cka_only_20_1p5b.log\\neval_gsm8k_grpo_cka_only_20_1p5b.json\\neval_gsm8k_grpo_rasp_20_1p5b.json\\neval_gsm8k_grpo_standard_20_1p5b.json\\neval_gsm8k_grpo_unstructured_20.json\\neval_gsm8k_seed123.log\\neval_gsm8k_sft_cka_only_20_1p5b.json\\neval_gsm8k_sft_cka_only_20_1p5b.log\\neval_gsm8k_sft_rasp_20_1p5b.json\\neval_gsm8k_sft_standard_20_1p5b.json\\neval_humaneval_grpo_standard_20_1p5b_2048.json\\neval_humaneval_grpo_standard_20_1p5b_2048.log\\neval_humaneval_sft_rasp_20_1p5b_2048.log\\neval_postprune_gradient_20.json\\neval_postprune_random_20.json\\neval_sft_cka_only_20.json\\neval_sft_random_20.json\\neval_sft_rasp_20_full.log\\neval_sft_rasp_20_full_n1319.json\\neval_sft_rasp_20_seed123.json\\neval_sft_rasp_20_seed456.json\\neval_sft_rasp_25.json\\neval_sft_rasp_rlvr_20.json\\neval_sft_standard_20_full.log\\neval_sft_standard_20_seed123.json\\neval_sft_standard_20_seed456.json\\neval_sft_standard_25.json\\neval_unstructured_20_n1319.json\\ngradient_flow\\ngradient_flow_v3\\ngroup_selection_comparison.csv\\ngroup_selection_comparison.json\\ngsm8k_grpo_cka_only_20.json\\ngsm8k_grpo_cka_only_20_seed123.json\\ngsm8k_pruned_cka_only_20_1p5b_quick.json\\ngsm8k_pruned_rasp_20_1p5b_quick.json\\ngsm8k_pruned_standard_20_1p5b_quick.json\\nhumaneval_sft_standard_20_1p5b_2048.json\\ninference_bench.log\\ninference_benchmark.json\\ninference_benchmark_cka_only.json\\ninference_benchmark_cka_only_clean.json\\ninference_speedup_plan016.log\\nmath500_grpo_cka_only_20.json\\nrandom_cka_ablation_log.txt\\nreeval_rasp_20_gpu0.json\\nreeval_standard_20_gpu1.json\\nsft_random_20.log\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.88}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "ed693d6e-409b-490d-938e-38e003546466",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"ablation_log.txt\\\\nbinary_outcomes_westb.json\\\\ncka_heatmap_cka_only.json\\\\ncka_heatmap_random.json\\\\ncka_heatmap_rasp.json\\\\ncka_heatmap_standard.json\\\\ncka_reliability_ablation.json\\\\ne3_cka_heatmap.pdf\\\\neval_cka_only_20_n200.json\\\\neval_gradient_postsft.json\\\\neval_gradient_sft.log\\\\neval_grpo_rasp_25_n1319.json\\\\neval_grpo_rasp_v9_step10.json\\\\neval_gsm8k_cka_only_20_1p5b.log\\\\neval_gsm8k_grpo_cka_only_20_1p5b.json\\\\neval_gsm8k_grpo_rasp_20_1p5b.json\\\\neval_gsm8k_grpo_standard_20_1p5b.json\\\\neval_gsm8k_grpo_unstructured_20.json\\\\neval_gsm8k_seed123.log\\\\neval_gsm8k_sft_cka_only_20_1p5b.json\\\\neval_gsm8k_sft_cka_only_20_1p5b.log\\\\neval_gsm8k_sft_rasp_20_1p5b.json\\\\neval_gsm8k_sft_standard_20_1p5b.json\\\\neval_humaneval_grpo_standard_20_1p5b_2048.json\\\\neval_humaneval_grpo_standard_20_1p5b_2048.log\\\\neval_humaneval_sft_rasp_20_1p5b_2048.log\\\\neval_postprune_gradient_20.json\\\\neval_postprune_random_20.json\\\\neval_sft_cka_only_20.json\\\\neval_sft_random_20.json\\\\neval_sft_rasp_20_full.log\\\\neval_sft_rasp_20_full_n1319.json\\\\neval_sft_rasp_20_seed123.json\\\\neval_sft_rasp_20_seed456.json\\\\neval_sft_rasp_25.json\\\\neval_sft_rasp_rlvr_20.json\\\\neval_sft_standard_20_full.log\\\\neval_sft_standard_20_seed123.json\\\\neval_sft_standard_20_seed456.json\\\\neval_sft_standard_25.json\\\\neval_unstructured_20_n1319.json\\\\ngradient_flow\\\\ngradient_flow_v3\\\\ngroup_selection_comparison.csv\\\\ngroup_selection_comparison.json\\\\ngsm8k_grpo_cka_only_20.json\\\\ngsm8k_grpo_cka_only_20_seed123.json\\\\ngsm8k_pruned_cka_only_20_1p5b_quick.json\\\\ngsm8k_pruned_rasp_20_1p5b_quick.json\\\\ngsm8k_pruned_standard_20_1p5b_quick.json\\\\nhumaneval_sft_standard_20_1p5b_2048.json\\\\ninference_bench.log\\\\ninference_benchmark.json\\\\ninference_benchmark_cka_only.json\\\\ninference_benchmark_cka_only_clean.json\\\\ninference_speedup_plan016.log\\\\nmath500_grpo_cka_only_20.json\\\\nrandom_cka_ablation_log.txt\\\\nreeval_rasp_20_gpu0.json\\\\nreeval_standard_20_gpu1.json\\\\nsft_random_20.log\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.88}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"ablation_log.txt\\nbinary_outcomes_westb.json\\ncka_heatmap_cka_only.json\\ncka_heatmap_random.json\\ncka_heatmap_rasp.json\\ncka_heatmap_standard.json\\ncka_reliability_ablation.json\\ne3_cka_heatmap.pdf\\neval_cka_only_20_n200.json\\neval_gradient_postsft.json\\neval_gradient_sft.log\\neval_grpo_rasp_25_n1319.json\\neval_grpo_rasp_v9_step10.json\\neval_gsm8k_cka_only_20_1p5b.log\\neval_gsm8k_grpo_cka_only_20_1p5b.json\\neval_gsm8k_grpo_rasp_20_1p5b.json\\neval_gsm8k_grpo_standard_20_1p5b.json\\neval_gsm8k_grpo_unstructured_20.json\\neval_gsm8k_seed123.log\\neval_gsm8k_sft_cka_only_20_1p5b.json\\neval_gsm8k_sft_cka_only_20_1p5b.log\\neval_gsm8k_sft_rasp_20_1p5b.json\\neval_gsm8k_sft_standard_20_1p5b.json\\neval_humaneval_grpo_standard_20_1p5b_2048.json\\neval_humaneval_grpo_standard_20_1p5b_2048.log\\neval_humaneval_sft_rasp_20_1p5b_2048.log\\neval_postprune_gradient_20.json\\neval_postprune_random_20.json\\neval_sft_cka_only_20.json\\neval_sft_random_20.json\\neval_sft_rasp_20_full.log\\neval_sft_rasp_20_full_n1319.json\\neval_sft_rasp_20_seed123.json\\neval_sft_rasp_20_seed456.json\\neval_sft_rasp_25.json\\neval_sft_rasp_rlvr_20.json\\neval_sft_standard_20_full.log\\neval_sft_standard_20_seed123.json\\neval_sft_standard_20_seed456.json\\neval_sft_standard_25.json\\neval_unstructured_20_n1319.json\\ngradient_flow\\ngradient_flow_v3\\ngroup_selection_comparison.csv\\ngroup_selection_comparison.json\\ngsm8k_grpo_cka_only_20.json\\ngsm8k_grpo_cka_only_20_seed123.json\\ngsm8k_pruned_cka_only_20_1p5b_quick.json\\ngsm8k_pruned_rasp_20_1p5b_quick.json\\ngsm8k_pruned_standard_20_1p5b_quick.json\\nhumaneval_sft_standard_20_1p5b_2048.json\\ninference_bench.log\\ninference_benchmark.json\\ninference_benchmark_cka_only.json\\ninference_benchmark_cka_only_clean.json\\ninference_speedup_plan016.log\\nmath500_grpo_cka_only_20.json\\nrandom_cka_ablation_log.txt\\nreeval_rasp_20_gpu0.json\\nreeval_standard_20_gpu1.json\\nsft_random_20.log\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.88}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 22_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01CuujTzgChiz1wCEh287Bpv`</summary>

```json
{
  "server": "westb-23072",
  "command": "find /root/recovery_aware_struct_prune/src/ -name \"run_cka_reliability*\" -o -name \"run_scoring_ablation*\"",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "f89ffb0a-0485-460a-9e1c-0b2fb2220d03",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W2fWpY4xFzxgEYt76VSEEw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5334,
      "cache_read_input_tokens": 25217,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5334
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

_source line 23 · 2026-05-19T18:24:56.339Z_

<details><summary>↩ Tool result · `toolu_01CuujTzgChiz1wCEh287Bpv`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/recovery_aware_struct_prune/src/run_cka_reliability.py\\n/root/recovery_aware_struct_prune/src/run_scoring_ablation.sh\\n/root/recovery_aware_struct_prune/src/run_scoring_ablation_continue.sh\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.81}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "a70bfe13-b850-4636-9e66-cbf0dba67dfc",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/recovery_aware_struct_prune/src/run_cka_reliability.py\\\\n/root/recovery_aware_struct_prune/src/run_scoring_ablation.sh\\\\n/root/recovery_aware_struct_prune/src/run_scoring_ablation_continue.sh\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.81}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/recovery_aware_struct_prune/src/run_cka_reliability.py\\n/root/recovery_aware_struct_prune/src/run_scoring_ablation.sh\\n/root/recovery_aware_struct_prune/src/run_scoring_ablation_continue.sh\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.81}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 24_

<details open><summary>🔧 Tool call — Agent · `toolu_01QX1X5L4s7Rxp6TDobbZ1at`</summary>

```json
{
  "description": "Query registry for 1.5B experiments",
  "prompt": "I need you to analyze a large JSON file containing experiment registry data. The file is at:\n/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt\n\nThis file has schema: {result: string} where result is a JSON string containing experiment entries.\n\nI need you to:\n1. Extract all experiments with \"1p5b\" or \"1.5b\" in the experiment_id/name — list their id, status, conclusion, and key metrics\n2. Extract all experiments with \"mbpp\" in the id/name — list their id, status, conclusion, and key metrics\n3. Extract all experiments with \"seed123\" in the id/name — list their id, status, conclusion, and key metrics\n4. Extract all experiments related to \"cka_reliability\" or \"scoring_ablation\" or \"plan_014\" — list their id, status, and conclusion\n5. List all RUNNING experiments\n\nUse jq or python to parse. Report findings concisely.",
  "subagent_type": "general-purpose"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "b5f7e686-5154-403f-8225-74477ab4d632",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01W2fWpY4xFzxgEYt76VSEEw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5334,
      "cache_read_input_tokens": 25217,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5334
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

### System

_source line 25_

```json
{
  "type": "system",
  "subtype": "task_started",
  "task_id": "a5932a6af8063e1b2",
  "tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "description": "Query registry for 1.5B experiments",
  "task_type": "local_agent",
  "prompt": "I need you to analyze a large JSON file containing experiment registry data. The file is at:\n/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt\n\nThis file has schema: {result: string} where result is a JSON string containing experiment entries.\n\nI need you to:\n1. Extract all experiments with \"1p5b\" or \"1.5b\" in the experiment_id/name — list their id, status, conclusion, and key metrics\n2. Extract all experiments with \"mbpp\" in the id/name — list their id, status, conclusion, and key metrics\n3. Extract all experiments with \"seed123\" in the id/name — list their id, status, conclusion, and key metrics\n4. Extract all experiments related to \"cka_reliability\" or \"scoring_ablation\" or \"plan_014\" — list their id, status, and conclusion\n5. List all RUNNING experiments\n\nUse jq or python to parse. Report findings concisely.",
  "uuid": "2deb2f73-6ea9-4cd9-a530-2fdc6502679b",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1"
}
```

---

## Round 1

36 recorded events

### User

_source line 26 · 2026-05-19T18:25:04.395Z_

I need you to analyze a large JSON file containing experiment registry data. The file is at:
/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt

This file has schema: {result: string} where result is a JSON string containing experiment entries.

I need you to:
1. Extract all experiments with "1p5b" or "1.5b" in the experiment_id/name — list their id, status, conclusion, and key metrics
2. Extract all experiments with "mbpp" in the id/name — list their id, status, conclusion, and key metrics
3. Extract all experiments with "seed123" in the id/name — list their id, status, conclusion, and key metrics
4. Extract all experiments related to "cka_reliability" or "scoring_ablation" or "plan_014" — list their id, status, and conclusion
5. List all RUNNING experiments

Use jq or python to parse. Report findings concisely.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "02bd316f-d191-44af-aae9-61c7c5483cc7"
}
```

</details>

---

### System

_source line 27_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a5932a6af8063e1b2",
  "tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "description": "Reading ~/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt",
  "usage": {
    "total_tokens": 14917,
    "tool_uses": 1,
    "duration_ms": 3700
  },
  "last_tool_name": "Read",
  "uuid": "69bb5767-1640-4c6c-a247-f3a39ea191d1",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1"
}
```

---

### Tool call

_source line 28_

<details open><summary>🔧 Tool call — Read · `toolu_01S221XkSQBJjvEY4YTpPtBC`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt",
  "limit": 50
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "1caa0f3d-2d41-46bc-be4e-c4944ff6c327",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011DL5TwXrpFEZcRqU1fg6j3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 14910,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 14910,
        "ephemeral_1h_input_tokens": 0
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

_source line 29 · 2026-05-19T18:25:08.388Z_

<details><summary>↩ Tool result · reported error · `toolu_01S221XkSQBJjvEY4YTpPtBC`</summary>

```text
File content (65283 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "3c23200b-1c6b-4c6b-ac44-cce7953c370f",
  "tool_use_result": "Error: File content (65283 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file."
}
```

</details>

---

### System

_source line 30_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a5932a6af8063e1b2",
  "tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "description": "Reading ~/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt",
  "usage": {
    "total_tokens": 15994,
    "tool_uses": 2,
    "duration_ms": 9191
  },
  "last_tool_name": "Read",
  "uuid": "aa51b553-ba73-491b-b0fb-5fbd1af41065",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1"
}
```

---

### Tool call

_source line 31_

<details open><summary>🔧 Tool call — Read · `toolu_01BQ53VuRCKQJjLTkEEUAJ16`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt",
  "limit": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "c8430a6a-28bf-4c2f-be64-92d78c2430f8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DV6CJFs3785ZVj1JnB8ytz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1077,
      "cache_read_input_tokens": 14910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1077,
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

_source line 32 · 2026-05-19T18:25:13.858Z_

<details><summary>↩ Tool result · reported error · `toolu_01BQ53VuRCKQJjLTkEEUAJ16`</summary>

```text
File content (65283 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "b7a13085-6056-45d8-811b-b894dfd0552b",
  "tool_use_result": "Error: File content (65283 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file."
}
```

</details>

---

### System

_source line 33_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a5932a6af8063e1b2",
  "tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "description": "Running Check file structure",
  "usage": {
    "total_tokens": 16275,
    "tool_uses": 3,
    "duration_ms": 12986
  },
  "last_tool_name": "Bash",
  "uuid": "3cdf63a2-bcf8-45c1-aa54-32179118c648",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1"
}
```

---

### Tool call

_source line 34_

<details open><summary>🔧 Tool call — Bash · `toolu_015sgSHWTwujmj9pvu4VDRBo`</summary>

```json
{
  "command": "head -c 500 \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt\"",
  "description": "Check file structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "9f6866ee-2e17-4e4e-8761-5afd3a6851b1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RvAzwPAK6fksJKcCm4jVWK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 237,
      "cache_read_input_tokens": 15987,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 237,
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

_source line 35 · 2026-05-19T18:25:17.575Z_

<details><summary>↩ Tool result · `toolu_015sgSHWTwujmj9pvu4VDRBo`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {\"eval_mbpp_grpo_rasp_20\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T18:18:35.729Z\", \"updated_at\": \"2026-05-19T18:24:28.539Z\", \"hypothesis\": \"MBPP pass@1 eval on GRPO RASP 20% model @2048. Dense baseline=53.48% (200/374). RASP GRPO GSM8K=60.88%, HumanEval=10.37%. Tests RASP GRPO code generation on MBPP. Completes MBPP 3×2 matrix. Expected: between CKA-only GRPO (14.17%) and Standard GRPO (running). Recovery gradient
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "43b82104-0fa6-46d9-ae16-7dc41be8e02d"
}
```

</details>

---

### System

_source line 36_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a5932a6af8063e1b2",
  "tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "description": "Running Parse registry JSON and extract experiment data for all 5 queries",
  "usage": {
    "total_tokens": 16730,
    "tool_uses": 4,
    "duration_ms": 33181
  },
  "last_tool_name": "Bash",
  "uuid": "d7f6d0e7-4de5-42d6-8fea-46e43c3d578c",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1"
}
```

---

### Tool call

_source line 37_

<details open><summary>🔧 Tool call — Bash · `toolu_017fGpyKN6cPqrQkwFoc44xC`</summary>

```json
{
  "command": "FILE=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt\"\n\npython3 << 'PYEOF'\nimport json\n\nwith open(\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt\") as f:\n    raw = json.load(f)\n\ninner = json.loads(raw[\"result\"])\nexperiments = inner[\"data\"][\"experiments\"]\n\nprint(f\"Total experiments: {len(experiments)}\")\nprint(\"---\")\n\n# 1. Experiments with \"1p5b\" or \"1.5b\"\nprint(\"\\n=== 1. Experiments with '1p5b' or '1.5b' ===\")\nfor eid, edata in experiments.items():\n    if \"1p5b\" in eid.lower() or \"1.5b\" in eid.lower():\n        status = edata.get(\"status\", \"N/A\")\n        conclusion = edata.get(\"conclusion\", \"N/A\")\n        metrics = edata.get(\"metrics\", edata.get(\"key_metrics\", {}))\n        print(f\"\\nID: {eid}\")\n        print(f\"  Status: {status}\")\n        print(f\"  Conclusion: {conclusion}\")\n        if metrics:\n            print(f\"  Metrics: {json.dumps(metrics, indent=4)}\")\n\n# 2. Experiments with \"mbpp\"\nprint(\"\\n\\n=== 2. Experiments with 'mbpp' ===\")\nfor eid, edata in experiments.items():\n    if \"mbpp\" in eid.lower():\n        status = edata.get(\"status\", \"N/A\")\n        conclusion = edata.get(\"conclusion\", \"N/A\")\n        metrics = edata.get(\"metrics\", edata.get(\"key_metrics\", {}))\n        print(f\"\\nID: {eid}\")\n        print(f\"  Status: {status}\")\n        print(f\"  Conclusion: {conclusion}\")\n        if metrics:\n            print(f\"  Metrics: {json.dumps(metrics, indent=4)}\")\n\n# 3. Experiments with \"seed123\"\nprint(\"\\n\\n=== 3. Experiments with 'seed123' ===\")\nfor eid, edata in experiments.items():\n    if \"seed123\" in eid.lower():\n        status = edata.get(\"status\", \"N/A\")\n        conclusion = edata.get(\"conclusion\", \"N/A\")\n        metrics = edata.get(\"metrics\", edata.get(\"key_metrics\", {}))\n        print(f\"\\nID: {eid}\")\n        print(f\"  Status: {status}\")\n        print(f\"  Conclusion: {conclusion}\")\n        if metrics:\n            print(f\"  Metrics: {json.dumps(metrics, indent=4)}\")\n\n# 4. Experiments with \"cka_reliability\", \"scoring_ablation\", \"plan_014\"\nprint(\"\\n\\n=== 4. Experiments with 'cka_reliability' / 'scoring_ablation' / 'plan_014' ===\")\nfor eid, edata in experiments.items():\n    if any(kw in eid.lower() for kw in [\"cka_reliability\", \"scoring_ablation\", \"plan_014\"]):\n        status = edata.get(\"status\", \"N/A\")\n        conclusion = edata.get(\"conclusion\", \"N/A\")\n        print(f\"\\nID: {eid}\")\n        print(f\"  Status: {status}\")\n        print(f\"  Conclusion: {conclusion}\")\n\n# 5. All RUNNING experiments\nprint(\"\\n\\n=== 5. All RUNNING experiments ===\")\nfor eid, edata in experiments.items():\n    if edata.get(\"status\", \"\").upper() == \"RUNNING\":\n        print(f\"\\nID: {eid}\")\n        hypothesis = edata.get(\"hypothesis\", \"N/A\")\n        print(f\"  Hypothesis: {hypothesis[:200]}...\")\n\nPYEOF",
  "description": "Parse registry JSON and extract experiment data for all 5 queries",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "146fd0c6-0a10-4f99-afa9-12fec7a3bdf4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018bLpVz33ZC1i24jTj9aLqd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 392,
      "cache_read_input_tokens": 16224,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 392,
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

_source line 38 · 2026-05-19T18:25:37.689Z_

<details><summary>↩ Tool result · `toolu_017fGpyKN6cPqrQkwFoc44xC`</summary>

```text
Total experiments: 227
---

=== 1. Experiments with '1p5b' or '1.5b' ===

ID: eval_humaneval_grpo_standard_20_1p5b_2048
  Status: DONE
  Conclusion: success

ID: eval_humaneval_sft_cka_only_20_1p5b_2048
  Status: DONE
  Conclusion: success
  Metrics: {
    "pass_at_1": 0.0061,
    "stderr": 0.0061,
    "n_correct": 1,
    "n_total": 164,
    "avg_response_length": 1968.8,
    "median_response_length": 2048
}

ID: eval_humaneval_grpo_cka_only_20_1p5b_2048
  Status: DONE
  Conclusion: success
  Metrics: {
    "pass_at_1": 0,
    "stderr": 0,
    "n_correct": 0,
    "n_total": 164,
    "avg_response_length": 1977.7,
    "median_response_length": 2048
}

ID: eval_humaneval_sft_standard_20_1p5b_2048
  Status: DONE
  Conclusion: success
  Metrics: {
    "pass_at_1": 0.0061,
    "n_correct": 1,
    "n_total": 164,
    "stderr": 0.0061
}

ID: eval_gsm8k_sft_standard_20_1p5b
  Status: DONE
  Conclusion: success
  Metrics: {
    "accuracy": 0.22896133434420016,
    "n_correct": 302,
    "n_total": 1319
}

ID: eval_gsm8k_sft_rasp_20_1p5b
  Status: DONE
  Conclusion: success
  Metrics: {
    "accuracy": 0.2691,
    "n_correct": 355,
    "n_total": 1319,
    "stderr": 0.0122,
    "grpo_delta_pp": -0.75
}

ID: eval_gsm8k_sft_cka_only_20_1p5b
  Status: DONE
  Conclusion: success
  Metrics: {
    "accuracy": 0.3563,
    "n_correct": 470,
    "n_total": 1319,
    "stderr": 0.0132,
    "eos_rate": 0.9507,
    "avg_response_length": 336.76
}

ID: eval_gsm8k_grpo_rasp_20_1p5b
  Status: DONE
  Conclusion: success
  Metrics: {
    "accuracy": 0.2616,
    "n_correct": 345,
    "n_total": 1319,
    "stderr": 0.0121,
    "eos_rate": 0.9378,
    "avg_response_length": 392.7
}

ID: eval_gsm8k_grpo_standard_20_1p5b
  Status: DONE
  Conclusion: success
  Metrics: {
    "accuracy": 0.2229,
    "n_correct": 294,
    "n_total": 1319,
    "stderr": 0.0115
}

ID: eval_gsm8k_grpo_cka_only_20_1p5b
  Status: DONE
  Conclusion: success
  Metrics: {
    "accuracy": 0.3548,
    "n_correct": 468,
    "n_total": 1319,
    "stderr": 0.0132
}

ID: grpo_rasp_20_1p5b
  Status: DONE
  Conclusion: success
  Metrics: {
    "final_reward": 0.099,
    "frac_zero_std": 0.175,
    "clipped_ratio": 0.82
}

ID: grpo_cka_only_20_1p5b
  Status: DONE
  Conclusion: success
  Metrics: {
    "reward_mean": 0.2375,
    "frac_reward_zero_std": 0.175,
    "loss": 0.0595,
    "kl": 0.00215,
    "grad_norm": 1.445,
    "global_step": 100,
    "note": "training completed 100/100 but save_model failed (disk full). checkpoint-100 has complete model."
}

ID: grpo_standard_20_1p5b
  Status: DONE
  Conclusion: success
  Metrics: {
    "reward_mean": 0.0844,
    "frac_reward_zero_std": 0.15,
    "loss": 0.0151,
    "grad_norm": 4.03125,
    "kl": 0.0044,
    "entropy": 0.4617,
    "final_step": 100,
    "max_steps": 100,
    "total_time_min": 53
}

ID: sft_standard_20_1p5b
  Status: DONE
  Conclusion: success

ID: sft_cka_only_20_1p5b
  Status: DONE
  Conclusion: success

ID: sft_rasp_20_1p5b
  Status: DONE
  Conclusion: success


=== 2. Experiments with 'mbpp' ===

ID: eval_mbpp_grpo_rasp_20
  Status: DONE
  Conclusion: failed

ID: eval_mbpp_sft_rasp_20
  Status: DONE
  Conclusion: failed

ID: eval_mbpp_grpo_cka_only_20
  Status: DONE
  Conclusion: success
  Metrics: {
    "pass_at_1": 0.1417,
    "n_correct": 53,
    "n_total": 374,
    "stderr": 0.018
}

ID: eval_mbpp_dense_unpruned
  Status: DONE
  Conclusion: success
  Metrics: {
    "pass_at_1": 0.5348,
    "stderr": 0.0258,
    "n_correct": 200,
    "n_total": 374
}


=== 3. Experiments with 'seed123' ===

ID: eval_gsm8k_grpo_cka_only_20_seed123
  Status: DONE
  Conclusion: success
  Metrics: {
    "accuracy": 0.6422,
    "stderr": 0.0132,
    "n_correct": 847,
    "n_total": 1319,
    "eos_rate": 0.9909,
    "avg_response_length": 195.97,
    "natural_eos": 1307,
    "truncated": 12
}

ID: grpo_cka_only_20_seed123
  Status: DONE
  Conclusion: success
  Metrics: {
    "train_loss": 0.1361,
    "final_step_loss": 0.05054,
    "final_reward": 0.2975,
    "final_reward_std": 0.4097,
    "train_steps": 100,
    "train_runtime_hours": 11.63,
    "wandb_run": "j8kn0sqd"
}

ID: eval_sft_standard_20_seed123
  Status: DONE
  Conclusion: failed

ID: eval_sft_rasp_20_seed123
  Status: DONE
  Conclusion: failed


=== 4. Experiments with 'cka_reliability' / 'scoring_ablation' / 'plan_014' ===

ID: scoring_ablation_magnitude_20
  Status: DONE
  Conclusion: failed

ID: scoring_ablation_batch_v2
  Status: DONE
  Conclusion: failed


=== 5. All RUNNING experiments ===
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "1d49ee5d-f42a-45a1-b59a-cbe94d1ebddf"
}
```

</details>

---

### System

_source line 39_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a5932a6af8063e1b2",
  "tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "description": "Running Get details on experiments with missing metrics and check status distribution",
  "usage": {
    "total_tokens": 19997,
    "tool_uses": 5,
    "duration_ms": 47745
  },
  "last_tool_name": "Bash",
  "uuid": "a30cbf4a-f73a-4b0a-8ef8-7111a6e19317",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1"
}
```

---

### Tool call

_source line 40_

<details open><summary>🔧 Tool call — Bash · `toolu_01VzbtaV6aQ6JidzyxM3NwUh`</summary>

```json
{
  "command": "python3 << 'PYEOF'\nimport json\n\nwith open(\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt\") as f:\n    raw = json.load(f)\n\ninner = json.loads(raw[\"result\"])\nexperiments = inner[\"data\"][\"experiments\"]\n\n# Check some experiments missing metrics for additional fields\nfor eid in [\"eval_humaneval_grpo_standard_20_1p5b_2048\", \"sft_standard_20_1p5b\", \"sft_cka_only_20_1p5b\", \"sft_rasp_20_1p5b\",\n            \"eval_mbpp_grpo_rasp_20\", \"eval_mbpp_sft_rasp_20\",\n            \"scoring_ablation_magnitude_20\", \"scoring_ablation_batch_v2\",\n            \"eval_sft_standard_20_seed123\", \"eval_sft_rasp_20_seed123\"]:\n    if eid in experiments:\n        e = experiments[eid]\n        print(f\"\\n--- {eid} ---\")\n        # Print all keys\n        for k, v in e.items():\n            if k in (\"hypothesis\",):\n                print(f\"  {k}: {str(v)[:200]}\")\n            else:\n                print(f\"  {k}: {v}\")\n\n# Also check all statuses\nprint(\"\\n\\n=== Status distribution ===\")\nfrom collections import Counter\nstatuses = Counter(e.get(\"status\",\"UNKNOWN\") for e in experiments.values())\nfor s, c in statuses.most_common():\n    print(f\"  {s}: {c}\")\n\nPYEOF",
  "description": "Get details on experiments with missing metrics and check status distribution",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "feca6b77-f94a-46f7-a42d-1101557d0e9c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H6y2oQMN3EQEF1HRpCWY8r",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3265,
      "cache_read_input_tokens": 16616,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3265,
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

_source line 41 · 2026-05-19T18:25:52.226Z_

<details><summary>↩ Tool result · `toolu_01VzbtaV6aQ6JidzyxM3NwUh`</summary>

```text
--- eval_humaneval_grpo_standard_20_1p5b_2048 ---
  status: DONE
  created_at: 2026-05-19T11:35:48.029Z
  updated_at: 2026-05-19T17:02:50.370Z
  hypothesis: 1.5B GRPO Standard HumanEval pass@1 @2048. Cross-scale validation baseline. 7B GRPO Standard HumanEval failed (multiple attempts). If 1.5B Standard also shows weak code generation after GRPO (vs CKA-o
  conclusion: success

--- sft_standard_20_1p5b ---
  status: DONE
  created_at: 2026-05-18T12:09:56.278Z
  updated_at: 2026-05-18T12:31:29.300Z
  hypothesis: Standard 20% SFT recovery on 1.5B model. Cross-model generalization test: if Standard SFT recovery pattern holds on 1.5B as on 7B. Paired with CKA-only and RASP 1.5B SFT for cross-scale comparison of 
  conclusion: success

--- sft_cka_only_20_1p5b ---
  status: DONE
  created_at: 2026-05-18T11:29:09.842Z
  updated_at: 2026-05-18T12:31:27.978Z
  hypothesis: CKA-only 20% SFT recovery on 1.5B model. Cross-model generalization test: if CKA-only SFT recovery pattern (high accuracy) holds on 1.5B as on 7B, validates that CKA-guided pruning preserves recovery 
  notes: Training completed 1870/1870 steps. Checkpoint save crashed (RuntimeError at inline_container.cc:668) due to disk 100% full. Model weights rescued from checkpoint-1870 (optimizer.pt truncated but model.safetensors intact). Checkpoints cleaned, model files promoted to output dir. Pending load validation.
  conclusion: success

--- sft_rasp_20_1p5b ---
  status: DONE
  created_at: 2026-05-18T12:09:57.178Z
  updated_at: 2026-05-18T12:29:19.746Z
  hypothesis: RASP 20% SFT recovery on 1.5B model. Cross-model generalization test: if RASP SFT recovery pattern holds on 1.5B as on 7B. Paired with CKA-only and Standard 1.5B SFT for cross-scale comparison of reco
  conclusion: success

--- eval_mbpp_grpo_rasp_20 ---
  status: DONE
  created_at: 2026-05-19T18:18:35.729Z
  updated_at: 2026-05-19T18:24:28.539Z
  hypothesis: MBPP pass@1 eval on GRPO RASP 20% model @2048. Dense baseline=53.48% (200/374). RASP GRPO GSM8K=60.88%, HumanEval=10.37%. Tests RASP GRPO code generation on MBPP. Completes MBPP 3×2 matrix. Expected: 
  conclusion: failed

--- eval_mbpp_sft_rasp_20 ---
  status: DONE
  created_at: 2026-05-19T18:18:34.640Z
  updated_at: 2026-05-19T18:23:21.466Z
  hypothesis: MBPP pass@1 eval on SFT RASP 20% model @2048. Dense baseline=53.48% (200/374). RASP SFT GSM8K=60.88% (post-GRPO), HumanEval SFT=10.37%. Tests whether RASP SFT preserves code capability on MBPP. Part o
  conclusion: failed
  notes: Model not found on westb. 7B SFT RASP checkpoint is on westd (sft_rasp_20_westd), not westb. Need to rerun on westd when GPU available.

--- scoring_ablation_magnitude_20 ---
  created_at: 2026-05-17T04:21:41.038Z
  hypothesis: Magnitude-only scoring (weight L2 norm per group) at 20% sparsity. Isolates contribution of gradient signal vs weight magnitude. If post-prune accuracy near 0% (as expected from heavy early-layer prun
  status: DONE
  updated_at: 2026-05-18T05:52:12.799Z
  conclusion: failed

--- scoring_ablation_batch_v2 ---
  conclusion: failed
  created_at: 2026-05-17T05:45:47.123Z
  hypothesis: Scoring ablation with controlled search space (MLP-only, --skip_attention): CKA-aware scoring (RASP) preserves more post-prune accuracy than magnitude-only, gradient-only, random, or CKA-only scoring 
  metrics: {'gradient_postprune': {'acc': 0.255, 'n_samples': 200, 'note': '25.5% - significantly better than magnitude (0%), gradient preserves some structure'}, 'gradient_sft': {'disk_issue': '/dev/md0 250G 100% full', 'reason': 'Disk full at step 935/1870 (50%)', 'status': 'FAILED'}, 'magnitude_postprune': {'acc': 0, 'avg_len': 4054, 'early_stopped': True, 'eos_rate': 0.02, 'n_samples': 60}, 'magnitude_sft': {'reason': 'Extreme per-layer non-uniformity, unrecoverable', 'status': 'FAILED'}, 'random_postprune': {'progress': '26/200', 'status': 'in_progress'}}
  notes: 失败原因: westb-23072 /dev/md0 (250G系统盘) 在 gradient_sft step 935/1870 时写满 | 已有成果: magnitude_postprune=0%(60样本,early_stop), magnitude_sft=FAILED(non-uniformity不可恢复), gradient_postprune=25.5%(200样本), random_postprune 仅完成 26/200 | gradient_sft 已由独立实验 gradient_sft_v3 成功完成 | 建议: 清理系统盘后重试，或拆分为独立实验分别跑(scoring_ablation_magnitude_20, scoring_ablation_random_20, scoring_ablation_cka_only_20 已在 PREPARING)
  parent: scoring_ablation_batch
  status: DONE
  updated_at: 2026-05-17T10:23:53.103Z

--- eval_sft_standard_20_seed123 ---
  conclusion: failed
  created_at: 2026-05-17T03:18:18.061Z
  hypothesis: Multi-seed variance estimation: Standard 20% post-SFT GSM8K accuracy should show low variance (std<3pp) across seeds, confirming seed=42 result (64%) is representative. Part of 5-seed suite for statis
  notes: westd-11672 服务器不可达 (SSH check failed 5x, Unable to connect to port 11672). 非代码问题，服务器恢复后需重跑。轻量 eval 任务 (n=200)。
  parent: sft_standard_20
  status: DONE
  updated_at: 2026-05-17T05:43:39.380Z

--- eval_sft_rasp_20_seed123 ---
  conclusion: failed
  created_at: 2026-05-17T03:18:16.149Z
  hypothesis: Multi-seed variance estimation: RASP 20% post-SFT GSM8K accuracy should show low variance (std<3pp) across seeds, confirming seed=42 result (57%) is representative. Part of 5-seed suite for statistica
  notes: westd-11672 服务器不可达 (SSH check failed 5x, Unable to connect to port 11672). 非代码问题，服务器恢复后需重跑。轻量 eval 任务 (n=200)。
  parent: sft_rasp_20
  status: DONE
  updated_at: 2026-05-17T05:43:38.035Z


=== Status distribution ===
  DONE: 227
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "b6c1a415-9727-40ac-b8c0-c812ab5779e8"
}
```

</details>

---

### System

_source line 42_

```json
{
  "type": "system",
  "subtype": "task_notification",
  "task_id": "a5932a6af8063e1b2",
  "tool_use_id": "toolu_01QX1X5L4s7Rxp6TDobbZ1at",
  "status": "completed",
  "output_file": "",
  "summary": "Query registry for 1.5B experiments",
  "usage": {
    "total_tokens": 22783,
    "tool_uses": 5,
    "duration_ms": 74650
  },
  "uuid": "c8b31aa1-0c1d-4559-9538-818e0d0b646c",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1"
}
```

---

### Tool result

_source line 43 · 2026-05-19T18:26:19.048Z_

<details><summary>↩ Tool result · `toolu_01QX1X5L4s7Rxp6TDobbZ1at`</summary>

```text
Here are the findings:

---

## 1. Experiments with "1p5b" / "1.5b" (16 total, all DONE/success)

**Training runs (3):**

| ID | Conclusion | Key Metrics |
|---|---|---|
| `grpo_rasp_20_1p5b` | success | final_reward=0.099, frac_zero_std=0.175, clipped_ratio=0.82 |
| `grpo_cka_only_20_1p5b` | success | reward_mean=0.2375, loss=0.0595, kl=0.00215 (disk full during save, checkpoint-100 intact) |
| `grpo_standard_20_1p5b` | success | reward_mean=0.0844, loss=0.0151, kl=0.0044, 53 min total |
| `sft_standard_20_1p5b` | success | (no metrics recorded) |
| `sft_cka_only_20_1p5b` | success | (disk full crash during checkpoint save; model rescued from checkpoint-1870) |
| `sft_rasp_20_1p5b` | success | (no metrics recorded) |

**GSM8K evals (6):**

| ID | Accuracy | n_correct/n_total |
|---|---|---|
| `eval_gsm8k_sft_cka_only_20_1p5b` | **35.63%** | 470/1319 |
| `eval_gsm8k_grpo_cka_only_20_1p5b` | **35.48%** | 468/1319 |
| `eval_gsm8k_sft_rasp_20_1p5b` | 26.91% | 355/1319 |
| `eval_gsm8k_grpo_rasp_20_1p5b` | 26.16% | 345/1319 |
| `eval_gsm8k_sft_standard_20_1p5b` | 22.90% | 302/1319 |
| `eval_gsm8k_grpo_standard_20_1p5b` | 22.29% | 294/1319 |

**HumanEval evals (4):**

| ID | pass@1 | n_correct/n_total |
|---|---|---|
| `eval_humaneval_sft_cka_only_20_1p5b_2048` | 0.61% | 1/164 |
| `eval_humaneval_sft_standard_20_1p5b_2048` | 0.61% | 1/164 |
| `eval_humaneval_grpo_cka_only_20_1p5b_2048` | 0% | 0/164 |
| `eval_humaneval_grpo_standard_20_1p5b_2048` | success (no metrics recorded) |

**Takeaway:** On 1.5B, CKA-only pruning dominates GSM8K (~35.5%) vs Standard (~22.5%), but all methods collapse on HumanEval (0-0.6%).

---

## 2. Experiments with "mbpp" (4 total, all DONE)

| ID | Status | Conclusion | Key Metrics |
|---|---|---|---|
| `eval_mbpp_dense_unpruned` | DONE | success | pass@1=**53.48%** (200/374) -- baseline |
| `eval_mbpp_grpo_cka_only_20` | DONE | success | pass@1=**14.17%** (53/374) |
| `eval_mbpp_grpo_rasp_20` | DONE | failed | (no metrics -- failure) |
| `eval_mbpp_sft_rasp_20` | DONE | failed | (model not found on westb; checkpoint is on westd, needs rerun) |

---

## 3. Experiments with "seed123" (4 total, all DONE)

| ID | Status | Conclusion | Key Metrics |
|---|---|---|---|
| `grpo_cka_only_20_seed123` | DONE | success | train_loss=0.1361, final_reward=0.2975, 11.63h runtime |
| `eval_gsm8k_grpo_cka_only_20_seed123` | DONE | success | accuracy=**64.22%** (847/1319), eos_rate=99.1% |
| `eval_sft_standard_20_seed123` | DONE | failed | Server unreachable (westd-11672 SSH failed 5x) |
| `eval_sft_rasp_20_seed123` | DONE | failed | Server unreachable (westd-11672 SSH failed 5x) |

**Note:** The two failed seed123 evals are infrastructure failures (server down), not code/model failures.

---

## 4. Experiments with "cka_reliability" / "scoring_ablation" / "plan_014" (2 total)

| ID | Status | Conclusion | Notes |
|---|---|---|---|
| `scoring_ablation_magnitude_20` | DONE | failed | (no detailed metrics) |
| `scoring_ablation_batch_v2` | DONE | failed | magnitude_postprune=0%, gradient_postprune=25.5%, gradient_sft failed (disk full at step 935/1870), random_postprune only 26/200 done |

No experiments matched "cka_reliability" or "plan_014".

---

## 5. RUNNING experiments

**None.** All 227 experiments have status DONE.

agentId: a5932a6af8063e1b2 (use SendMessage with to: 'a5932a6af8063e1b2' to continue this agent)
&lt;usage>total_tokens: 24083
tool_uses: 5
duration_ms: 74652&lt;/usage>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "f5fa2821-24cb-4ff9-bbc6-5c16644f5109",
  "tool_use_result": {
    "status": "completed",
    "prompt": "I need you to analyze a large JSON file containing experiment registry data. The file is at:\n/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-17-projects-recovery-aware-struct-prune/d24dd67d-247f-4de1-8e6b-d350286085b1/tool-results/mcp-agent-ml-research-read_registry-1779215077988.txt\n\nThis file has schema: {result: string} where result is a JSON string containing experiment entries.\n\nI need you to:\n1. Extract all experiments with \"1p5b\" or \"1.5b\" in the experiment_id/name — list their id, status, conclusion, and key metrics\n2. Extract all experiments with \"mbpp\" in the id/name — list their id, status, conclusion, and key metrics\n3. Extract all experiments with \"seed123\" in the id/name — list their id, status, conclusion, and key metrics\n4. Extract all experiments related to \"cka_reliability\" or \"scoring_ablation\" or \"plan_014\" — list their id, status, and conclusion\n5. List all RUNNING experiments\n\nUse jq or python to parse. Report findings concisely.",
    "agentId": "a5932a6af8063e1b2",
    "agentType": "general-purpose",
    "content": [
      {
        "type": "text",
        "text": "Here are the findings:\n\n---\n\n## 1. Experiments with \"1p5b\" / \"1.5b\" (16 total, all DONE/success)\n\n**Training runs (3):**\n\n| ID | Conclusion | Key Metrics |\n|---|---|---|\n| `grpo_rasp_20_1p5b` | success | final_reward=0.099, frac_zero_std=0.175, clipped_ratio=0.82 |\n| `grpo_cka_only_20_1p5b` | success | reward_mean=0.2375, loss=0.0595, kl=0.00215 (disk full during save, checkpoint-100 intact) |\n| `grpo_standard_20_1p5b` | success | reward_mean=0.0844, loss=0.0151, kl=0.0044, 53 min total |\n| `sft_standard_20_1p5b` | success | (no metrics recorded) |\n| `sft_cka_only_20_1p5b` | success | (disk full crash during checkpoint save; model rescued from checkpoint-1870) |\n| `sft_rasp_20_1p5b` | success | (no metrics recorded) |\n\n**GSM8K evals (6):**\n\n| ID | Accuracy | n_correct/n_total |\n|---|---|---|\n| `eval_gsm8k_sft_cka_only_20_1p5b` | **35.63%** | 470/1319 |\n| `eval_gsm8k_grpo_cka_only_20_1p5b` | **35.48%** | 468/1319 |\n| `eval_gsm8k_sft_rasp_20_1p5b` | 26.91% | 355/1319 |\n| `eval_gsm8k_grpo_rasp_20_1p5b` | 26.16% | 345/1319 |\n| `eval_gsm8k_sft_standard_20_1p5b` | 22.90% | 302/1319 |\n| `eval_gsm8k_grpo_standard_20_1p5b` | 22.29% | 294/1319 |\n\n**HumanEval evals (4):**\n\n| ID | pass@1 | n_correct/n_total |\n|---|---|---|\n| `eval_humaneval_sft_cka_only_20_1p5b_2048` | 0.61% | 1/164 |\n| `eval_humaneval_sft_standard_20_1p5b_2048` | 0.61% | 1/164 |\n| `eval_humaneval_grpo_cka_only_20_1p5b_2048` | 0% | 0/164 |\n| `eval_humaneval_grpo_standard_20_1p5b_2048` | success (no metrics recorded) |\n\n**Takeaway:** On 1.5B, CKA-only pruning dominates GSM8K (~35.5%) vs Standard (~22.5%), but all methods collapse on HumanEval (0-0.6%).\n\n---\n\n## 2. Experiments with \"mbpp\" (4 total, all DONE)\n\n| ID | Status | Conclusion | Key Metrics |\n|---|---|---|---|\n| `eval_mbpp_dense_unpruned` | DONE | success | pass@1=**53.48%** (200/374) -- baseline |\n| `eval_mbpp_grpo_cka_only_20` | DONE | success | pass@1=**14.17%** (53/374) |\n| `eval_mbpp_grpo_rasp_20` | DONE | failed | (no metrics -- failure) |\n| `eval_mbpp_sft_rasp_20` | DONE | failed | (model not found on westb; checkpoint is on westd, needs rerun) |\n\n---\n\n## 3. Experiments with \"seed123\" (4 total, all DONE)\n\n| ID | Status | Conclusion | Key Metrics |\n|---|---|---|---|\n| `grpo_cka_only_20_seed123` | DONE | success | train_loss=0.1361, final_reward=0.2975, 11.63h runtime |\n| `eval_gsm8k_grpo_cka_only_20_seed123` | DONE | success | accuracy=**64.22%** (847/1319), eos_rate=99.1% |\n| `eval_sft_standard_20_seed123` | DONE | failed | Server unreachable (westd-11672 SSH failed 5x) |\n| `eval_sft_rasp_20_seed123` | DONE | failed | Server unreachable (westd-11672 SSH failed 5x) |\n\n**Note:** The two failed seed123 evals are infrastructure failures (server down), not code/model failures.\n\n---\n\n## 4. Experiments with \"cka_reliability\" / \"scoring_ablation\" / \"plan_014\" (2 total)\n\n| ID | Status | Conclusion | Notes |\n|---|---|---|---|\n| `scoring_ablation_magnitude_20` | DONE | failed | (no detailed metrics) |\n| `scoring_ablation_batch_v2` | DONE | failed | magnitude_postprune=0%, gradient_postprune=25.5%, gradient_sft failed (disk full at step 935/1870), random_postprune only 26/200 done |\n\nNo experiments matched \"cka_reliability\" or \"plan_014\".\n\n---\n\n## 5. RUNNING experiments\n\n**None.** All 227 experiments have status DONE."
      }
    ],
    "totalDurationMs": 74652,
    "totalTokens": 24083,
    "totalToolUseCount": 5,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2785,
      "cache_read_input_tokens": 19881,
      "output_tokens": 1416,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2785
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1416,
          "cache_read_input_tokens": 19881,
          "cache_creation_input_tokens": 2785,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2785,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "toolStats": {
      "readCount": 2,
      "searchCount": 0,
      "bashCount": 3,
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

_source line 44_

<details><summary>Logged reasoning block</summary>

```text
Let me now check what's actually running on westb GPUs and verify the current state.

From the nvidia-smi output, there's only 1 python process using GPU (4314 MiB on one GPU). Let me figure out which GPU it's on and what it's running.

Let me also check the eval_mbpp.py code and the CKA reliability script to understand readiness for plan_014.

Let me also check what MBPP evals are still needed - from the registry:


- `eval_mbpp_dense_unpruned`: DONE, pass@1=53.48%
- `eval_mbpp_grpo_cka_only_20`: DONE, pass@1=14.17%
- `eval_mbpp_grpo_rasp_20`: DONE, failed
- `eval_mbpp_sft_rasp_20`: DONE, failed (model not on westb)

From ROADMAP, MBPP matrix needs SFT methods with RASP GRPO, and westd:2 is already running `eval_mbpp_grpo_standard_20`. For the 1.5B MBPP evals, none have completed yet.

Let me check what's currently running on westb:0 and westb:1.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "29298f70-de13-4e7f-9689-a7c5451554b5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXkhCEEy3bFCmsftTpmadZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 4061,
      "cache_read_input_tokens": 30551,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4061
      },
      "output_tokens": 16,
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

_source line 45_

Let me check which GPU the running process is on and what experiment it is.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "d58d7c25-904f-4710-bae1-75dbb7115cc9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXkhCEEy3bFCmsftTpmadZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 4061,
      "cache_read_input_tokens": 30551,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4061
      },
      "output_tokens": 16,
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

_source line 46_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01KayY4y1pC2rVKsuTKG41U9`</summary>

```json
{
  "server": "westb-23072",
  "command": "nvidia-smi --query-gpu=index,gpu_uuid,memory.used --format=csv,noheader",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "ef9140f0-d5be-4c27-9d5d-6069da92f0bf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXkhCEEy3bFCmsftTpmadZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 4061,
      "cache_read_input_tokens": 30551,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4061
      },
      "output_tokens": 16,
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

_source line 47 · 2026-05-19T18:26:51.960Z_

<details><summary>↩ Tool result · `toolu_01KayY4y1pC2rVKsuTKG41U9`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"0, GPU-549a7198-85c3-248c-9f75-5b8d5ff146f4, 4323 MiB\\n1, GPU-7b195135-ddad-2206-ed75-0d99e677e086, 0 MiB\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.87}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "72995c24-19b6-4e8b-81f0-caf388b1ef30",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"0, GPU-549a7198-85c3-248c-9f75-5b8d5ff146f4, 4323 MiB\\\\n1, GPU-7b195135-ddad-2206-ed75-0d99e677e086, 0 MiB\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.87}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"0, GPU-549a7198-85c3-248c-9f75-5b8d5ff146f4, 4323 MiB\\n1, GPU-7b195135-ddad-2206-ed75-0d99e677e086, 0 MiB\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.87}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 48_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01Cza52ZPCVonJtTF1NC9iLv`</summary>

```json
{
  "server": "westb-23072",
  "command": "ps -p 909411 -o pid,cmd --no-headers",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "ff3ba7d9-f1a7-4052-9a2a-9c45de0c4a80",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXkhCEEy3bFCmsftTpmadZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 4061,
      "cache_read_input_tokens": 30551,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4061
      },
      "output_tokens": 16,
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

_source line 49 · 2026-05-19T18:26:52.883Z_

<details><summary>↩ Tool result · `toolu_01Cza52ZPCVonJtTF1NC9iLv`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"909411 python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_1p5b --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/eval_humaneval_sft_rasp_20_1p5b_2048.json --seed 42\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.86}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "61559729-141c-404d-ab88-6eae6292579b",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"909411 python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_1p5b --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/eval_humaneval_sft_rasp_20_1p5b_2048.json --seed 42\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.86}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"909411 python src/eval_humaneval.py --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_rasp_20_1p5b --max_new_tokens 2048 --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/eval_humaneval_sft_rasp_20_1p5b_2048.json --seed 42\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.86}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 50_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01Nq8yh3b92CnAMe8Yd2mtfD`</summary>

```json
{
  "server": "westb-23072",
  "command": "head -30 /root/recovery_aware_struct_prune/src/run_cka_reliability.py",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "2a874d0e-2c10-4d0f-8512-781fb8b3bbee",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXkhCEEy3bFCmsftTpmadZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 4061,
      "cache_read_input_tokens": 30551,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4061
      },
      "output_tokens": 16,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01X5K5EBi7aYCtkD8cJVpWty`</summary>

```json
{
  "server": "westb-23072",
  "command": "head -50 /root/recovery_aware_struct_prune/src/eval_mbpp.py",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "d17527b6-302a-4644-8110-1ebc10aa8e56",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXkhCEEy3bFCmsftTpmadZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 4061,
      "cache_read_input_tokens": 30551,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4061
      },
      "output_tokens": 16,
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

_source line 52 · 2026-05-19T18:26:54.191Z_

<details><summary>↩ Tool result · `toolu_01Nq8yh3b92CnAMe8Yd2mtfD`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"\\nCKA Reliability Analysis for RASP.\\n\\nValidates the stability of cross-model CKA scores (original vs pruned) by:\\n1. Split-half reliability: Spearman rho between CKA scores on two data halves\\n2. Calibration size sensitivity: Spearman rho at different sample sizes vs full\\n\\nAddresses Claim 2: CKA-based structural scoring is reliable and stable.\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport os\\nimport random\\nimport sys\\n\\nimport numpy as np\\nimport scipy.stats as stats\\nimport torch\\nfrom datasets import load_dataset\\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s [%(levelname)s] %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\n\\ndef set_seed(seed):\\n    random.seed(seed)\\n    np.random.seed(seed)\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.8}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "f483d32b-b793-43a2-a533-e6620fde54a1",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"\\\\nCKA Reliability Analysis for RASP.\\\\n\\\\nValidates the stability of cross-model CKA scores (original vs pruned) by:\\\\n1. Split-half reliability: Spearman rho between CKA scores on two data halves\\\\n2. Calibration size sensitivity: Spearman rho at different sample sizes vs full\\\\n\\\\nAddresses Claim 2: CKA-based structural scoring is reliable and stable.\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nimport argparse\\\\nimport json\\\\nimport logging\\\\nimport os\\\\nimport random\\\\nimport sys\\\\n\\\\nimport numpy as np\\\\nimport scipy.stats as stats\\\\nimport torch\\\\nfrom datasets import load_dataset\\\\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\\\\n\\\\nlogging.basicConfig(level=logging.INFO, format=\\\\\\\"%(asctime)s [%(levelname)s] %(message)s\\\\\\\")\\\\nlogger = logging.getLogger(__name__)\\\\n\\\\n\\\\ndef set_seed(seed):\\\\n    random.seed(seed)\\\\n    np.random.seed(seed)\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.8}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"\\nCKA Reliability Analysis for RASP.\\n\\nValidates the stability of cross-model CKA scores (original vs pruned) by:\\n1. Split-half reliability: Spearman rho between CKA scores on two data halves\\n2. Calibration size sensitivity: Spearman rho at different sample sizes vs full\\n\\nAddresses Claim 2: CKA-based structural scoring is reliable and stable.\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport os\\nimport random\\nimport sys\\n\\nimport numpy as np\\nimport scipy.stats as stats\\nimport torch\\nfrom datasets import load_dataset\\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s [%(levelname)s] %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\n\\ndef set_seed(seed):\\n    random.seed(seed)\\n    np.random.seed(seed)\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.8}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 53 · 2026-05-19T18:26:55.111Z_

<details><summary>↩ Tool result · `toolu_01X5K5EBi7aYCtkD8cJVpWty`</summary>

````text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"MBPP (Mostly Basic Python Problems) Evaluation.\\n\\nEvaluates code generation models on MBPP sanitized subset (374 tasks).\\nUses sandbox execution to verify generated code against test cases.\\n\\\"\\\"\\\"\\n\\nimport argparse\\nfrom datetime import datetime\\nimport json\\nimport logging\\nimport math\\nimport os\\nimport random\\nimport re\\nimport sys\\nimport subprocess\\nimport tempfile\\n\\nimport numpy as np\\nimport torch\\nfrom datasets import load_dataset\\nfrom transformers import AutoTokenizer\\nfrom model_utils import load_pruned_model\\nfrom tqdm import tqdm\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s [%(levelname)s] %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\n\\ndef set_seed(seed):\\n    random.seed(seed)\\n    np.random.seed(seed)\\n    torch.manual_seed(seed)\\n    torch.cuda.manual_seed_all(seed)\\n\\n\\ndef extract_code_block(text):\\n    \\\"\\\"\\\"Extract Python code from model response, handling markdown fences and think tags.\\\"\\\"\\\"\\n    clean = re.sub(r\\\"&lt;think>.*?&lt;/think>\\\", \\\"\\\", text, flags=re.DOTALL)\\n    if not clean.strip():\\n        clean = text\\n    code_blocks = re.findall(r\\\"```python\\\\s*\\\\n(.*?)```\\\", clean, re.DOTALL)\\n    if code_blocks:\\n        return code_blocks[0]\\n    code_blocks = re.findall(r\\\"```\\\\s*\\\\n(.*?)```\\\", clean, re.DOTALL)\\n    if code_blocks:\\n        return code_blocks[0]\\n    return clean\\n\\n\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9}}"}
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "e3bf0ab2-bc04-49a8-b519-322a39c7d8ed",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"MBPP (Mostly Basic Python Problems) Evaluation.\\\\n\\\\nEvaluates code generation models on MBPP sanitized subset (374 tasks).\\\\nUses sandbox execution to verify generated code against test cases.\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nimport argparse\\\\nfrom datetime import datetime\\\\nimport json\\\\nimport logging\\\\nimport math\\\\nimport os\\\\nimport random\\\\nimport re\\\\nimport sys\\\\nimport subprocess\\\\nimport tempfile\\\\n\\\\nimport numpy as np\\\\nimport torch\\\\nfrom datasets import load_dataset\\\\nfrom transformers import AutoTokenizer\\\\nfrom model_utils import load_pruned_model\\\\nfrom tqdm import tqdm\\\\n\\\\nlogging.basicConfig(level=logging.INFO, format=\\\\\\\"%(asctime)s [%(levelname)s] %(message)s\\\\\\\")\\\\nlogger = logging.getLogger(__name__)\\\\n\\\\n\\\\ndef set_seed(seed):\\\\n    random.seed(seed)\\\\n    np.random.seed(seed)\\\\n    torch.manual_seed(seed)\\\\n    torch.cuda.manual_seed_all(seed)\\\\n\\\\n\\\\ndef extract_code_block(text):\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"Extract Python code from model response, handling markdown fences and think tags.\\\\\\\"\\\\\\\"\\\\\\\"\\\\n    clean = re.sub(r\\\\\\\"&lt;think>.*?&lt;/think>\\\\\\\", \\\\\\\"\\\\\\\", text, flags=re.DOTALL)\\\\n    if not clean.strip():\\\\n        clean = text\\\\n    code_blocks = re.findall(r\\\\\\\"```python\\\\\\\\s*\\\\\\\\n(.*?)```\\\\\\\", clean, re.DOTALL)\\\\n    if code_blocks:\\\\n        return code_blocks[0]\\\\n    code_blocks = re.findall(r\\\\\\\"```\\\\\\\\s*\\\\\\\\n(.*?)```\\\\\\\", clean, re.DOTALL)\\\\n    if code_blocks:\\\\n        return code_blocks[0]\\\\n    return clean\\\\n\\\\n\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.9}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"MBPP (Mostly Basic Python Problems) Evaluation.\\n\\nEvaluates code generation models on MBPP sanitized subset (374 tasks).\\nUses sandbox execution to verify generated code against test cases.\\n\\\"\\\"\\\"\\n\\nimport argparse\\nfrom datetime import datetime\\nimport json\\nimport logging\\nimport math\\nimport os\\nimport random\\nimport re\\nimport sys\\nimport subprocess\\nimport tempfile\\n\\nimport numpy as np\\nimport torch\\nfrom datasets import load_dataset\\nfrom transformers import AutoTokenizer\\nfrom model_utils import load_pruned_model\\nfrom tqdm import tqdm\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s [%(levelname)s] %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\n\\ndef set_seed(seed):\\n    random.seed(seed)\\n    np.random.seed(seed)\\n    torch.manual_seed(seed)\\n    torch.cuda.manual_seed_all(seed)\\n\\n\\ndef extract_code_block(text):\\n    \\\"\\\"\\\"Extract Python code from model response, handling markdown fences and think tags.\\\"\\\"\\\"\\n    clean = re.sub(r\\\"&lt;think>.*?&lt;/think>\\\", \\\"\\\", text, flags=re.DOTALL)\\n    if not clean.strip():\\n        clean = text\\n    code_blocks = re.findall(r\\\"```python\\\\s*\\\\n(.*?)```\\\", clean, re.DOTALL)\\n    if code_blocks:\\n        return code_blocks[0]\\n    code_blocks = re.findall(r\\\"```\\\\s*\\\\n(.*?)```\\\", clean, re.DOTALL)\\n    if code_blocks:\\n        return code_blocks[0]\\n    return clean\\n\\n\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9}}"
    }
  }
}
````

</details>

---

### Assistant

_source line 54_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture:

**Current state:**
- westb:0 is running `eval_humaneval_sft_rasp_20_1p5b_2048` (PID 909411, 4323 MiB) — this aligns with what the user said
- westb:1 is free (0 MiB memory used)

**Available checkpoints on westb (1.5B series):**
- `sft_cka_only_20_1p5b` (2.8G)
- `sft_rasp_20_1p5b` (2.8G) — being evaluated on westb:0


- `sft_standard_20_1p5b` (2.8G)
- `grpo_cka_only_20_1p5b` (2.8G)
- `grpo_rasp_20_1p5b` (2.8G)
- `grpo_standard_20_1p5b` (2.8G)
- `pruned_cka_only_20_1p5b` (2.8G)
- `pruned_rasp_20_1p5b` (2.8G)
- `pruned_standard_20_1p5b` (2.8G)

So there are 7 other checkpoints available to run on westb:1, all in the same 1.5B model family with similar sizes.

Now looking at the larger 7B checkpoints I have access to — there's a good range of SFT variants like the CKA-only, random, RASP, and gradient approaches, plus the standard and RASP 25 versions. The GRPO checkpoints include some interesting variants, though one seed variant is unusually large at 38G and another appears corrupted. There are also various pruned 7B models available, and according to the registry, all of these have already been processed.

For the evaluation work, I've completed the 1.5B GSM8K evals and most of the HumanEval runs, but I'm still waiting on the RASP variants — one is currently running on westb. On the MBPP side, I've got results from the dense unpruned model and a few GRPO variants, though some failed due to model availability issues. There's an MBPP eval for the standard GRPO model running on westd right now, and I need to figure out what's still missing from the full evaluation suite.

Looking at what I can tackle next, the 1.5B MBPP evaluations haven't been run yet and would be a good fit for westb:1 since those checkpoints are small. I should prioritize either running those MBPP evals or getting the missing 1.5B HumanEval RASP variant done, depending on what makes the most sense for the current bottleneck. Looking at the ROADMAP more carefully, GRPO CKA is already complete and GRPO Standard is running on westd:2, so the MBPP matrix actually needs the SFT variants across all three methods plus a GRPO RASP rerun — all 7B models that would require substantial GPU memory. For the 1.5B HumanEval matrix, the only gap is the GRPO RASP variant since the SFT RASP is already in progress on westb:0.

Weighing the options, running the 1.5B HumanEval GRPO RASP evaluation would be quickest since the checkpoint is small (~2.8G) and readily available, while the MBPP SFT entries would be higher impact for completing that matrix but would need more GPU resources. I could start with the 1.5B model on westb:1 and then shift to the MBPP evaluations once that finishes. I should run the 1.5B HumanEval model first since it's quick, then move on to the 7B MBPP evaluation. Let me check the eval_mbpp.py script to make sure I have the right command format before presenting my recommendations.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "4e4efa7a-d625-47b0-a990-4b9cd846ef46",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KtqpGQkjByfYjMCb98cZVd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2136,
      "cache_read_input_tokens": 34612,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2136
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

_source line 55_

Now I have the full picture. Let me check the eval_mbpp.py CLI interface to confirm the command format.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "ef9b7589-a3b8-4851-9836-fe69b2da3f7e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KtqpGQkjByfYjMCb98cZVd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2136,
      "cache_read_input_tokens": 34612,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2136
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

_source line 56_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01FHYFEk7F346Ag6kgQFivmH`</summary>

```json
{
  "server": "westb-23072",
  "command": "grep -n \"add_argument\\|argparse\" /root/recovery_aware_struct_prune/src/eval_mbpp.py",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "fe8f411e-0096-4cd2-9246-f325aacf190d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KtqpGQkjByfYjMCb98cZVd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2136,
      "cache_read_input_tokens": 34612,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2136
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

_source line 57 · 2026-05-19T18:27:38.932Z_

<details><summary>↩ Tool result · `toolu_01FHYFEk7F346Ag6kgQFivmH`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "52ca6102-3fe2-42f8-b419-03d726f157dd",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 58_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01Gtw51QUCePLXw6v8HHfnmf`</summary>

```json
{
  "server": "westb-23072",
  "command": "grep -n \"add_argument\" /root/recovery_aware_struct_prune/src/eval_mbpp.py",
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
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "dacf4f2c-5e1e-4060-be93-4ee1025f47f9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QyHyJofBRbmYnawwPgjyV5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2102,
      "cache_read_input_tokens": 36748,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2102
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

_source line 59 · 2026-05-19T18:27:42.554Z_

<details><summary>↩ Tool result · `toolu_01Gtw51QUCePLXw6v8HHfnmf`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"86:    parser.add_argument(\\\"--model_path\\\", type=str, required=True)\\n87:    parser.add_argument(\\\"--output_path\\\", type=str, default=None)\\n88:    parser.add_argument(\\\"--max_new_tokens\\\", type=int, default=2048)\\n89:    parser.add_argument(\\\"--max_samples\\\", type=int, default=None)\\n90:    parser.add_argument(\\\"--seed\\\", type=int, default=42)\\n91:    parser.add_argument(\\\"--dtype\\\", type=str, default=\\\"bfloat16\\\")\\n92:    parser.add_argument(\\\"--timeout\\\", type=int, default=10)\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.8}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "b1754373-d049-4f44-9d3c-ccede9563e22",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"86:    parser.add_argument(\\\\\\\"--model_path\\\\\\\", type=str, required=True)\\\\n87:    parser.add_argument(\\\\\\\"--output_path\\\\\\\", type=str, default=None)\\\\n88:    parser.add_argument(\\\\\\\"--max_new_tokens\\\\\\\", type=int, default=2048)\\\\n89:    parser.add_argument(\\\\\\\"--max_samples\\\\\\\", type=int, default=None)\\\\n90:    parser.add_argument(\\\\\\\"--seed\\\\\\\", type=int, default=42)\\\\n91:    parser.add_argument(\\\\\\\"--dtype\\\\\\\", type=str, default=\\\\\\\"bfloat16\\\\\\\")\\\\n92:    parser.add_argument(\\\\\\\"--timeout\\\\\\\", type=int, default=10)\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.8}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"86:    parser.add_argument(\\\"--model_path\\\", type=str, required=True)\\n87:    parser.add_argument(\\\"--output_path\\\", type=str, default=None)\\n88:    parser.add_argument(\\\"--max_new_tokens\\\", type=int, default=2048)\\n89:    parser.add_argument(\\\"--max_samples\\\", type=int, default=None)\\n90:    parser.add_argument(\\\"--seed\\\", type=int, default=42)\\n91:    parser.add_argument(\\\"--dtype\\\", type=str, default=\\\"bfloat16\\\")\\n92:    parser.add_argument(\\\"--timeout\\\", type=int, default=10)\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.8}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 60_

汇总如下：

---

## westb 当前状态

| GPU | 占用 | 实验 |
|-----|------|------|
| westb:0 | 4323 MiB | `eval_humaneval_sft_rasp_20_1p5b_2048` (PID 909411) |
| westb:1 | **0 MiB — 空闲** | — |

## westb 上所有可用 checkpoint

**1.5B 系列 (每个 ~2.8G):**
| Checkpoint | 类型 |
|---|---|
| `pruned_cka_only_20_1p5b` | post-prune |
| `pruned_rasp_20_1p5b` | post-prune |
| `pruned_standard_20_1p5b` | post-prune |
| `sft_cka_only_20_1p5b` | SFT recovery |
| `sft_rasp_20_1p5b` | SFT recovery |
| `sft_standard_20_1p5b` | SFT recovery |
| `grpo_cka_only_20_1p5b` | GRPO recovery |
| `grpo_rasp_20_1p5b` | GRPO recovery |
| `grpo_standard_20_1p5b` | GRPO recovery |

**7B 系列 (每个 ~11-12G):**
sft/grpo/pruned × {cka_only_20, random_20, rasp_25, standard_25, rasp_rlvr_20, gradient_20} + `grpo_cka_only_20_seed123` (38G, 含多 checkpoint)

## Registry 缺口分析

**1.5B HumanEval 矩阵 — 差 1 个:**
- ✅ sft_cka_only (0.61%), sft_standard (0.61%), grpo_cka_only (0%), grpo_standard (done)
- 🔄 sft_rasp → westb:0 正在跑
- ❌ **grpo_rasp** → 未跑，checkpoint 在 westb

**MBPP 7B 矩阵 — 差 4 个:**
- ✅ Dense (53.48%), GRPO CKA-only (14.17%)
- 🔄 GRPO Standard → westd:2 正在跑
- ❌ **SFT CKA-only, SFT Standard, SFT RASP, GRPO RASP** → 全未跑，7B checkpoint 都在 westb

**CKA scoring stability (plan_014):** `run_cka_reliability.py` 代码存在，但 registry 中无 plan_014 实验记录。之前 `scoring_ablation_batch_v2` 失败（磁盘满）。代码 ready，需要 base model。

---

## 建议方案

**方案 A（推荐）：先快后慢，两阶段**

**阶段 1** — `eval_humaneval_grpo_rasp_20_1p5b_2048`（westb:1）
- 1.5B 模型仅 2.8G，HumanEval 164 题，预计 ~20-30 min
- 补全 1.5B HumanEval 矩阵最后一格
- Hypothesis: GRPO RASP 1.5B HumanEval ≈ 0%（与其他 1.5B 方法一致，1.5B 模型容量不足以做 code gen）

```bash
CUDA_VISIBLE_DEVICES=1 python src/eval_humaneval.py \
  --model_path /root/autodl-tmp/recovery_aware_struct_prune/grpo_rasp_20_1p5b \
  --max_new_tokens 2048 \
  --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/eval_humaneval_grpo_rasp_20_1p5b_2048.json \
  --seed 42
```

**阶段 2** — `eval_mbpp_sft_cka_only_20`（westb:1，阶段1完成后）
- MBPP P0 矩阵最关键的一格：CKA-only SFT
- 7B 模型 12G，可放入 westb:1
- Hypothesis: SFT CKA-only MBPP > SFT Standard/RASP（与 GSM8K/HumanEval 一致的 capability breadth 优势）

```bash
CUDA_VISIBLE_DEVICES=1 python src/eval_mbpp.py \
  --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20 \
  --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/eval_mbpp_sft_cka_only_20.json \
  --max_new_tokens 2048 --seed 42
```

**方案 B（如果 Director 想优先 plan_014）：** CKA reliability ablation 代码 ready，但需要确认 base model（`models/` 目录 3.4G）和校准数据集是否完整。之前 `scoring_ablation_batch_v2` 因磁盘满失败，需确认 `/root/autodl-tmp/` 空间足够。

**建议走方案 A** — 两个 eval 都是 ROADMAP P0 的 MBPP 矩阵和 1.5B cross-scale 补全，直接填论文表格。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "uuid": "194ed9ae-0615-46cb-99aa-52c50d413049",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Y412fQvjwSVns4MiTV4vVT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 403,
      "cache_read_input_tokens": 38850,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 403
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

### Task result

_source line 61_

汇总如下：

---

## westb 当前状态

| GPU | 占用 | 实验 |
|-----|------|------|
| westb:0 | 4323 MiB | `eval_humaneval_sft_rasp_20_1p5b_2048` (PID 909411) |
| westb:1 | **0 MiB — 空闲** | — |

## westb 上所有可用 checkpoint

**1.5B 系列 (每个 ~2.8G):**
| Checkpoint | 类型 |
|---|---|
| `pruned_cka_only_20_1p5b` | post-prune |
| `pruned_rasp_20_1p5b` | post-prune |
| `pruned_standard_20_1p5b` | post-prune |
| `sft_cka_only_20_1p5b` | SFT recovery |
| `sft_rasp_20_1p5b` | SFT recovery |
| `sft_standard_20_1p5b` | SFT recovery |
| `grpo_cka_only_20_1p5b` | GRPO recovery |
| `grpo_rasp_20_1p5b` | GRPO recovery |
| `grpo_standard_20_1p5b` | GRPO recovery |

**7B 系列 (每个 ~11-12G):**
sft/grpo/pruned × {cka_only_20, random_20, rasp_25, standard_25, rasp_rlvr_20, gradient_20} + `grpo_cka_only_20_seed123` (38G, 含多 checkpoint)

## Registry 缺口分析

**1.5B HumanEval 矩阵 — 差 1 个:**
- ✅ sft_cka_only (0.61%), sft_standard (0.61%), grpo_cka_only (0%), grpo_standard (done)
- 🔄 sft_rasp → westb:0 正在跑
- ❌ **grpo_rasp** → 未跑，checkpoint 在 westb

**MBPP 7B 矩阵 — 差 4 个:**
- ✅ Dense (53.48%), GRPO CKA-only (14.17%)
- 🔄 GRPO Standard → westd:2 正在跑
- ❌ **SFT CKA-only, SFT Standard, SFT RASP, GRPO RASP** → 全未跑，7B checkpoint 都在 westb

**CKA scoring stability (plan_014):** `run_cka_reliability.py` 代码存在，但 registry 中无 plan_014 实验记录。之前 `scoring_ablation_batch_v2` 失败（磁盘满）。代码 ready，需要 base model。

---

## 建议方案

**方案 A（推荐）：先快后慢，两阶段**

**阶段 1** — `eval_humaneval_grpo_rasp_20_1p5b_2048`（westb:1）
- 1.5B 模型仅 2.8G，HumanEval 164 题，预计 ~20-30 min
- 补全 1.5B HumanEval 矩阵最后一格
- Hypothesis: GRPO RASP 1.5B HumanEval ≈ 0%（与其他 1.5B 方法一致，1.5B 模型容量不足以做 code gen）

```bash
CUDA_VISIBLE_DEVICES=1 python src/eval_humaneval.py \
  --model_path /root/autodl-tmp/recovery_aware_struct_prune/grpo_rasp_20_1p5b \
  --max_new_tokens 2048 \
  --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/eval_humaneval_grpo_rasp_20_1p5b_2048.json \
  --seed 42
```

**阶段 2** — `eval_mbpp_sft_cka_only_20`（westb:1，阶段1完成后）
- MBPP P0 矩阵最关键的一格：CKA-only SFT
- 7B 模型 12G，可放入 westb:1
- Hypothesis: SFT CKA-only MBPP > SFT Standard/RASP（与 GSM8K/HumanEval 一致的 capability breadth 优势）

```bash
CUDA_VISIBLE_DEVICES=1 python src/eval_mbpp.py \
  --model_path /root/autodl-tmp/recovery_aware_struct_prune/sft_cka_only_20 \
  --output_path /root/autodl-tmp/recovery_aware_struct_prune/results/eval_mbpp_sft_cka_only_20.json \
  --max_new_tokens 2048 --seed 42
```

**方案 B（如果 Director 想优先 plan_014）：** CKA reliability ablation 代码 ready，但需要确认 base model（`models/` 目录 3.4G）和校准数据集是否完整。之前 `scoring_ablation_batch_v2` 因磁盘满失败，需确认 `/root/autodl-tmp/` 空间足够。

**建议走方案 A** — 两个 eval 都是 ROADMAP P0 的 MBPP 矩阵和 1.5B cross-scale 补全，直接填论文表格。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 231933,
  "duration_api_ms": 225835,
  "num_turns": 16,
  "stop_reason": "end_turn",
  "session_id": "d24dd67d-247f-4de1-8e6b-d350286085b1",
  "total_cost_usd": 0.7032305,
  "usage": {
    "input_tokens": 13,
    "cache_creation_input_tokens": 27412,
    "cache_read_input_tokens": 201910,
    "output_tokens": 6090,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 27412,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 1515,
        "cache_read_input_tokens": 38850,
        "cache_creation_input_tokens": 403,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 403
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1549,
      "outputTokens": 20,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.001649,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 21,
      "outputTokens": 9829,
      "cacheReadInputTokens": 285528,
      "cacheCreationInputTokens": 50078,
      "webSearchRequests": 0,
      "costUSD": 0.7015815,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "b947f163-9230-44ef-a1dd-779de5474b94"
}
```

</details>

---
