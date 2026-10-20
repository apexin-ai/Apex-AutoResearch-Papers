# paper lora param and table10 fix

**Not All Models Are Inflated: Profiling Contamination Dose-Response Across Model Families** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 43
- **Recorded user turns:** 0
- **Tool calls:** 14
- **Original source:** `logs/workers/worker_paper_lora-param-and-table10-fix_20260521T195543.log`
- **Structured JSON:** [`f41692f52e6d23ad596f.json`](../../sessions/f4/f41692f52e6d23ad596f.json)

## Before a recorded user message

43 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration",
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
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
  "uuid": "6df56786-4991-4258-a367-0ad28d3541e3",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-13-projects-contamcal-irt-calibration/memory/"
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
    "resetsAt": 1779406200,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "06657664-c879-45b2-8839-d058d6973ed2",
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me break this into parallel tasks. I need to:

1. Find and edit the Limitations section for LoRA parameters
2. Check server directories and edit Table 10 in appendix.tex

Let me start by reading the paper files and checking the server simultaneously.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "30694f48-95dc-4c79-8252-ae2985448209",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NJHQLCnag99qfeVAT2eHAy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13951,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13951
      },
      "output_tokens": 26,
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

I'll work on both tasks in parallel — reading the paper files and checking the server directories simultaneously.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "d2e7f7f3-b315-4817-8851-4ca235e89799",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NJHQLCnag99qfeVAT2eHAy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13951,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13951
      },
      "output_tokens": 26,
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

<details open><summary>🔧 Tool call — Glob · `toolu_01UFyve5XqTE6m2CxN5LhdTV`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "a7bcabf2-c9a8-40de-9e16-db0f353bf950",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NJHQLCnag99qfeVAT2eHAy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13951,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13951
      },
      "output_tokens": 26,
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

_source line 7 · 2026-05-21T19:56:03.212Z_

<details><summary>↩ Tool result · `toolu_01UFyve5XqTE6m2CxN5LhdTV`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "fd844b55-c1cc-470d-a1a0-8e5040273367",
  "tool_use_result": {
    "filenames": [],
    "durationMs": 6,
    "numFiles": 0,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 8_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_011res89wUTmwY48CwNyf1Pt`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only",
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
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "e0fe29d2-2984-436c-913e-3637e68d3b53",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NJHQLCnag99qfeVAT2eHAy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13951,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13951
      },
      "output_tokens": 26,
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

_source line 9 · 2026-05-21T19:56:03.533Z_

<details><summary>↩ Tool result · `toolu_011res89wUTmwY48CwNyf1Pt`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__ssh_read_only"
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
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "0320a7a2-3608-4493-b37e-86cb1929c0ee",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__ssh_read_only"
    ],
    "query": "select:mcp__agent-ml-research__ssh_read_only",
    "total_deferred_tools": 26
  }
}
```

</details>

---

### Assistant

_source line 10_

<details><summary>Logged reasoning block</summary>

```text
No .tex files found with that glob. Let me check what's actually in the paper directory.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "a809fe18-5765-438a-9652-553ce37f84f8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Eb2oCbjuMfkQCJ5nnTL8C5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 652,
      "cache_read_input_tokens": 25792,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 652
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

_source line 11_

<details open><summary>🔧 Tool call — Glob · `toolu_013qH9xKaZGXPGPgEdCn1goJ`</summary>

```json
{
  "pattern": "**/*",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "8cc3438f-a1c3-4577-995f-4559a5727514",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Eb2oCbjuMfkQCJ5nnTL8C5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 652,
      "cache_read_input_tokens": 25792,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 652
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

_source line 12 · 2026-05-21T19:56:09.269Z_

<details><summary>↩ Tool result · `toolu_013qH9xKaZGXPGPgEdCn1goJ`</summary>

```text
paper/sections/method.md
paper/sections/discussion.md
paper/sections/experimental_setup.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "3b8f956b-8644-4eab-b215-3e558fa60d9d",
  "tool_use_result": {
    "filenames": [
      "paper/sections/method.md",
      "paper/sections/discussion.md",
      "paper/sections/experimental_setup.md"
    ],
    "durationMs": 11,
    "numFiles": 3,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 13_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01EuY9FAjPffnpB7hyMDBrTi`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "ls /root/autodl-tmp/exp006/gamma_prior_sensitivity_j16/"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "e3c396e7-5d55-48be-a3ad-bc51bc1de98e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Eb2oCbjuMfkQCJ5nnTL8C5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 652,
      "cache_read_input_tokens": 25792,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 652
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

_source line 14_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01KxA4YhUEhCTYXT167HiENh`</summary>

```json
{
  "server": "cqa1-21977",
  "command": "ls /root/autodl-tmp/exp006/gamma_prior_sensitivity/"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "961221cf-f3ad-46e6-b217-9edc3e5a8613",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Eb2oCbjuMfkQCJ5nnTL8C5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 652,
      "cache_read_input_tokens": 25792,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 652
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

_source line 15 · 2026-05-21T19:56:10.748Z_

<details><summary>↩ Tool result · `toolu_01EuY9FAjPffnpB7hyMDBrTi`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"social_sciences\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.95}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "ea06afaf-0a28-4317-a651-5d45643020fc",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"social_sciences\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.95}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"social_sciences\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.95}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-21T19:56:11.220Z_

<details><summary>↩ Tool result · `toolu_01KxA4YhUEhCTYXT167HiENh`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"gamma_prior_sensitivity_results.json\\nsocial_sciences\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.46}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "ecc79e4c-3082-49da-a223-6617f736c2bb",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"gamma_prior_sensitivity_results.json\\\\nsocial_sciences\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.46}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"gamma_prior_sensitivity_results.json\\nsocial_sciences\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.46}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 17_

<details><summary>Logged reasoning block</summary>

```text
So the paper directory only has markdown files in `paper/sections/`. But the task mentions `.tex` files (appendix.tex). Let me look more broadly for tex files in the project.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "a1a57956-ae53-4e61-8393-6e1674a71689",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Es5kd5h3cUxGGvdHMtQLh8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 592,
      "cache_read_input_tokens": 26444,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 592
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

_source line 18_

The paper directory only has markdown section files. Let me search more broadly for the tex files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "2f4039c5-2e9a-4e5c-959c-12005da085d9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Es5kd5h3cUxGGvdHMtQLh8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 592,
      "cache_read_input_tokens": 26444,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 592
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

_source line 19_

<details open><summary>🔧 Tool call — Glob · `toolu_01RTy4n4EtXbGyc2qghyNx2C`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "50e23713-0187-4dfb-a0c7-dcae964e6e65",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Es5kd5h3cUxGGvdHMtQLh8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 592,
      "cache_read_input_tokens": 26444,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 592
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

_source line 20 · 2026-05-21T19:56:18.325Z_

<details><summary>↩ Tool result · `toolu_01RTy4n4EtXbGyc2qghyNx2C`</summary>

```text
artifacts/dream_reports/dream_20260513T155040/best/paper.tex
artifacts/dream_reports/dream_20260513T155040/median/paper.tex
artifacts/dream_reports/dream_20260513T155040/worst/paper.tex
artifacts/_project/paper/related_work.tex
artifacts/dream_reports/dream_20260513T171200/best/paper.tex
artifacts/dream_reports/dream_20260513T171200/median/paper.tex
artifacts/dream_reports/dream_20260513T171200/worst/paper.tex
artifacts/_project/paper/fisher_info_appendix.tex
artifacts/fisher_info_derivation/fisher_info_appendix.tex
artifacts/dream_reports/dream_20260514T171536/best/paper.tex
artifacts/dream_reports/dream_20260514T171536/median/paper.tex
artifacts/dream_reports/dream_20260514T171536/worst/paper.tex
artifacts/dream_reports/dream_20260514T185145/best/paper.tex
artifacts/dream_reports/dream_20260514T185145/median/paper.tex
artifacts/dream_reports/dream_20260514T185145/worst/paper.tex
artifacts/dream_reports/dream_20260515T052337/best/paper.tex
artifacts/dream_reports/dream_20260515T052337/median/paper.tex
artifacts/dream_reports/dream_20260515T052337/worst/paper.tex
artifacts/dream_reports/dream_20260516T104822/best/paper.tex
artifacts/dream_reports/dream_20260516T104822/median/paper.tex
artifacts/dream_reports/dream_20260516T104822/worst/paper.tex
artifacts/dream_reports/dream_20260516T155748/best/paper.tex
artifacts/dream_reports/dream_20260516T155748/median/paper.tex
artifacts/dream_reports/dream_20260516T155748/worst/paper.tex
artifacts/_project/paper/results.tex
artifacts/_project/paper/related_work_04a735.tex
artifacts/_project/paper/discussion.tex
artifacts/_project/paper/abstract.tex
artifacts/paper_draft/experiments.tex
artifacts/_project/paper/introduction.tex
artifacts/paper_draft/abstract.tex
artifacts/paper_draft/conclusion.tex
artifacts/paper_draft/discussion.tex
artifacts/paper_draft/introduction.tex
artifacts/paper_draft/main.tex
artifacts/paper_draft/method.tex
artifacts/paper_draft/related_work.tex
artifacts/paper_draft/results.tex
artifacts/paper_draft/experimental_setup.tex
docs/paper/ethics.tex
artifacts/_project/paper/algorithm1_pseudocode.tex
artifacts/_project/paper/algorithm1_pseudocode_c1bd81.tex
artifacts/algorithm1_pseudocode.tex
docs/paper/main.tex
docs/paper/introduction.tex
docs/paper/conclusion.tex
docs/paper/limitations.tex
docs/paper/abstract.tex
docs/paper/experimental_setup.tex
docs/paper/related_work.tex
docs/paper/results.tex
docs/paper/method.tex
docs/paper/appendix.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "895e64e8-3593-4549-b9b0-beab5f8ac605",
  "tool_use_result": {
    "filenames": [
      "artifacts/dream_reports/dream_20260513T155040/best/paper.tex",
      "artifacts/dream_reports/dream_20260513T155040/median/paper.tex",
      "artifacts/dream_reports/dream_20260513T155040/worst/paper.tex",
      "artifacts/_project/paper/related_work.tex",
      "artifacts/dream_reports/dream_20260513T171200/best/paper.tex",
      "artifacts/dream_reports/dream_20260513T171200/median/paper.tex",
      "artifacts/dream_reports/dream_20260513T171200/worst/paper.tex",
      "artifacts/_project/paper/fisher_info_appendix.tex",
      "artifacts/fisher_info_derivation/fisher_info_appendix.tex",
      "artifacts/dream_reports/dream_20260514T171536/best/paper.tex",
      "artifacts/dream_reports/dream_20260514T171536/median/paper.tex",
      "artifacts/dream_reports/dream_20260514T171536/worst/paper.tex",
      "artifacts/dream_reports/dream_20260514T185145/best/paper.tex",
      "artifacts/dream_reports/dream_20260514T185145/median/paper.tex",
      "artifacts/dream_reports/dream_20260514T185145/worst/paper.tex",
      "artifacts/dream_reports/dream_20260515T052337/best/paper.tex",
      "artifacts/dream_reports/dream_20260515T052337/median/paper.tex",
      "artifacts/dream_reports/dream_20260515T052337/worst/paper.tex",
      "artifacts/dream_reports/dream_20260516T104822/best/paper.tex",
      "artifacts/dream_reports/dream_20260516T104822/median/paper.tex",
      "artifacts/dream_reports/dream_20260516T104822/worst/paper.tex",
      "artifacts/dream_reports/dream_20260516T155748/best/paper.tex",
      "artifacts/dream_reports/dream_20260516T155748/median/paper.tex",
      "artifacts/dream_reports/dream_20260516T155748/worst/paper.tex",
      "artifacts/_project/paper/results.tex",
      "artifacts/_project/paper/related_work_04a735.tex",
      "artifacts/_project/paper/discussion.tex",
      "artifacts/_project/paper/abstract.tex",
      "artifacts/paper_draft/experiments.tex",
      "artifacts/_project/paper/introduction.tex",
      "artifacts/paper_draft/abstract.tex",
      "artifacts/paper_draft/conclusion.tex",
      "artifacts/paper_draft/discussion.tex",
      "artifacts/paper_draft/introduction.tex",
      "artifacts/paper_draft/main.tex",
      "artifacts/paper_draft/method.tex",
      "artifacts/paper_draft/related_work.tex",
      "artifacts/paper_draft/results.tex",
      "artifacts/paper_draft/experimental_setup.tex",
      "docs/paper/ethics.tex",
      "artifacts/_project/paper/algorithm1_pseudocode.tex",
      "artifacts/_project/paper/algorithm1_pseudocode_c1bd81.tex",
      "artifacts/algorithm1_pseudocode.tex",
      "docs/paper/main.tex",
      "docs/paper/introduction.tex",
      "docs/paper/conclusion.tex",
      "docs/paper/limitations.tex",
      "docs/paper/abstract.tex",
      "docs/paper/experimental_setup.tex",
      "docs/paper/related_work.tex",
      "docs/paper/results.tex",
      "docs/paper/method.tex",
      "docs/paper/appendix.tex"
    ],
    "durationMs": 57,
    "numFiles": 53,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 21_

<details open><summary>🔧 Tool call — Glob · `toolu_01A9h1hP1wHXg2qavHPbvUnP`</summary>

```json
{
  "pattern": "**/*appendix*",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "a6109c57-5b64-470c-9273-45f5963baaab",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Es5kd5h3cUxGGvdHMtQLh8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 592,
      "cache_read_input_tokens": 26444,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 592
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

_source line 22 · 2026-05-21T19:56:19.450Z_

<details><summary>↩ Tool result · `toolu_01A9h1hP1wHXg2qavHPbvUnP`</summary>

```text
artifacts/_project/paper/fisher_info_appendix.tex
artifacts/fisher_info_derivation/fisher_info_appendix.aux
artifacts/fisher_info_derivation/fisher_info_appendix.pdf
artifacts/fisher_info_derivation/fisher_info_appendix.log
artifacts/fisher_info_derivation/fisher_info_appendix.tex
logs/workers/worker_paper_figure_fig_signal_heatmap_appendix_20260516T205400.log
artifacts/_project/paper/appendix_domain_decomposition.md
artifacts/appendix_domain_decomposition.md
logs/workers/worker_analysis_domain-decomposition-appendix_20260519T214934.log
logs/chats/worker_analysis_domain-decomposition-appendix_20260519T214934.lock
logs/chats/worker_analysis_domain-decomposition-appendix_20260519T214934.jsonl
logs/workers/worker_analysis_domain-decomposition-appendix_20260519T214934_result.json
logs/workers/worker_research_gsm8k-appendix-gap_20260521T110638.log
logs/workers/worker_research_gsm8k-appendix-gap_20260521T110638_result.json
docs/paper/appendix.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "b20af853-af6f-4094-97b1-93cc1cf2b0e6",
  "tool_use_result": {
    "filenames": [
      "artifacts/_project/paper/fisher_info_appendix.tex",
      "artifacts/fisher_info_derivation/fisher_info_appendix.aux",
      "artifacts/fisher_info_derivation/fisher_info_appendix.pdf",
      "artifacts/fisher_info_derivation/fisher_info_appendix.log",
      "artifacts/fisher_info_derivation/fisher_info_appendix.tex",
      "logs/workers/worker_paper_figure_fig_signal_heatmap_appendix_20260516T205400.log",
      "artifacts/_project/paper/appendix_domain_decomposition.md",
      "artifacts/appendix_domain_decomposition.md",
      "logs/workers/worker_analysis_domain-decomposition-appendix_20260519T214934.log",
      "logs/chats/worker_analysis_domain-decomposition-appendix_20260519T214934.lock",
      "logs/chats/worker_analysis_domain-decomposition-appendix_20260519T214934.jsonl",
      "logs/workers/worker_analysis_domain-decomposition-appendix_20260519T214934_result.json",
      "logs/workers/worker_research_gsm8k-appendix-gap_20260521T110638.log",
      "logs/workers/worker_research_gsm8k-appendix-gap_20260521T110638_result.json",
      "docs/paper/appendix.tex"
    ],
    "durationMs": 62,
    "numFiles": 15,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 23_

<details open><summary>🔧 Tool call — Glob · `toolu_01QQrgcSFYc8XSgnXctb1aHQ`</summary>

```json
{
  "pattern": "**/*limitation*",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "7eb7fd5a-6900-4419-808f-92fa288712e3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Es5kd5h3cUxGGvdHMtQLh8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 592,
      "cache_read_input_tokens": 26444,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 592
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

_source line 24 · 2026-05-21T19:56:19.652Z_

<details><summary>↩ Tool result · `toolu_01QQrgcSFYc8XSgnXctb1aHQ`</summary>

```text
docs/paper/limitations.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "9b038746-f688-4bd1-8870-04083e2d87cf",
  "tool_use_result": {
    "filenames": [
      "docs/paper/limitations.tex"
    ],
    "durationMs": 60,
    "numFiles": 1,
    "truncated": false
  }
}
```

</details>

---

### Assistant

_source line 25_

<details><summary>Logged reasoning block</summary>

```text
Found the files: `docs/paper/limitations.tex` and `docs/paper/appendix.tex`. Let me read both.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "dab103ea-e64d-4a07-8172-aac5ac2ca5fd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PHLPaNrkPMMcts8KCM19uh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1641,
      "cache_read_input_tokens": 27036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1641
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

Found the files in `docs/paper/`. Let me read both the limitations and appendix files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "5465ab7a-2991-4a9f-bf08-a27ce6ec40bb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PHLPaNrkPMMcts8KCM19uh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1641,
      "cache_read_input_tokens": 27036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1641
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

<details open><summary>🔧 Tool call — Read · `toolu_01VYatdWPtSubcAsiAemzjXV`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "9b877f25-f442-4580-9f4d-8f0d707be5bf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PHLPaNrkPMMcts8KCM19uh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1641,
      "cache_read_input_tokens": 27036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1641
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

_source line 28 · 2026-05-21T19:56:23.029Z_

<details><summary>↩ Tool result · `toolu_01VYatdWPtSubcAsiAemzjXV`</summary>

```text
1	\section*{Limitations}
2	\label{sec:limitations}
3	
4	All experiments use models at or below 14.7B parameters; 70B+ models may exhibit qualitatively different contamination dynamics where SFT injection is absorbed without measurable signal divergence. With $n\!=\!3$ seeds per family, effect \emph{direction} is reproducible but magnitude is seed-sensitive (OLMo-2's cross-seed CI crosses zero, rendering its Benefit classification borderline), and borderline classifications should be interpreted with caution. Finally, our LoRA-based SFT injection in AUGMENT mode differs from pretraining-stage leakage via web crawl ingestion, and our dosage levels assume uniform injection of all benchmark items; real-world contamination may follow skewed exposure distributions, potentially producing different dose-response profiles. Unified LoRA rank ($r\!=\!16$) yields a parameter fraction inversely proportional to model size; Phi-4's immunity may partly reflect insufficient adaptation capacity, though Qwen-14B's collapse at the same scale argues against a purely capacity-based explanation. Out-of-sample validation covers only the Immune pattern; independent-family replication of Collapse, V-recovery, and Benefit remains open. All single-family patterns are, however, replicated across three random seeds. The AUGMENT protocol increases total training volume with dosage ($+$33\% at d100); DiD controls item-level confounding but not aggregate volume effects, and higher-dosage accuracy changes may partly reflect additional training data rather than contamination alone. IRT is fitted on the 300 highest-exposure-variance items (2.1\% of MMLU); contamination effects on the remaining low-variance items may differ. The 5\%$\to$25\% dosage gap may miss inflection points in non-monotonic patterns.
5	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "246ca61b-4570-486e-99f2-8050d9f421f4",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/limitations.tex",
      "content": "\\section*{Limitations}\n\\label{sec:limitations}\n\nAll experiments use models at or below 14.7B parameters; 70B+ models may exhibit qualitatively different contamination dynamics where SFT injection is absorbed without measurable signal divergence. With $n\\!=\\!3$ seeds per family, effect \\emph{direction} is reproducible but magnitude is seed-sensitive (OLMo-2's cross-seed CI crosses zero, rendering its Benefit classification borderline), and borderline classifications should be interpreted with caution. Finally, our LoRA-based SFT injection in AUGMENT mode differs from pretraining-stage leakage via web crawl ingestion, and our dosage levels assume uniform injection of all benchmark items; real-world contamination may follow skewed exposure distributions, potentially producing different dose-response profiles. Unified LoRA rank ($r\\!=\\!16$) yields a parameter fraction inversely proportional to model size; Phi-4's immunity may partly reflect insufficient adaptation capacity, though Qwen-14B's collapse at the same scale argues against a purely capacity-based explanation. Out-of-sample validation covers only the Immune pattern; independent-family replication of Collapse, V-recovery, and Benefit remains open. All single-family patterns are, however, replicated across three random seeds. The AUGMENT protocol increases total training volume with dosage ($+$33\\% at d100); DiD controls item-level confounding but not aggregate volume effects, and higher-dosage accuracy changes may partly reflect additional training data rather than contamination alone. IRT is fitted on the 300 highest-exposure-variance items (2.1\\% of MMLU); contamination effects on the remaining low-variance items may differ. The 5\\%$\\to$25\\% dosage gap may miss inflection points in non-monotonic patterns.\n",
      "numLines": 5,
      "startLine": 1,
      "totalLines": 5
    }
  }
}
```

</details>

---

### Tool call

_source line 29_

<details open><summary>🔧 Tool call — Read · `toolu_01DAVhgH7m9SZ6Kghmjw76hR`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "89e80051-7f64-485d-94e1-0449a03a8830",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PHLPaNrkPMMcts8KCM19uh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1641,
      "cache_read_input_tokens": 27036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1641
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

_source line 30 · 2026-05-21T19:56:23.897Z_

<details><summary>↩ Tool result · `toolu_01DAVhgH7m9SZ6Kghmjw76hR`</summary>

```text
1	\appendix
2	
3	\section{Cross-Benchmark Transfer Details}
4	\label{sec:cross_benchmark_details}
5	
6	\begin{table}[h]
7	\centering
8	\caption{Cross-benchmark transfer: MMLU vs.\ GSM8K accuracy change at d100. LLaMA-3.1 shows the strongest asymmetric transfer ($+$16.4pp GSM8K despite MMLU immunity). Gemma-2 excluded due to CoT collapse under MC-format SFT.}
9	\label{tab:gsm8k_transfer}
10	\footnotesize
11	\begin{tabular}{lcccl}
12	\toprule
13	Model & MMLU $\Delta$ & GSM8K $\Delta$ & Range & Transfer \\
14	\midrule
15	Phi-4 14.7B & $\pm$0.5pp & $-$0.5pp & --- & Null \\
16	OLMo-2 7B & $+$3.2pp & $+$2.1pp$^{\S}$ & --- & Consistent \\
17	Qwen-7B & $-$1.8pp & $+$10.1pp & $\pm$0.9 & Reversal \\
18	Qwen-14B & $-$9.4pp & $+$13.1pp & $\pm$7.4 & Reversal$^{\dagger}$ \\
19	LLaMA-3.1 8B & $-$0.7pp & $+$16.4pp$^{\ddagger}$ & --- & Asymmetric \\
20	\bottomrule
21	\multicolumn{5}{l}{\scriptsize $^{\dagger}$d000 baseline seed-sensitive (s42$=$60.8\% vs.\ s123$=$76.7\%); d100 stable ($82\pm0.5$\%).} \\
22	\multicolumn{5}{l}{\scriptsize $^{\S}$Seed$=$42; OLMo-2 GSM8K effect is seed-sensitive (s42: $+$2.1pp vs.\ s0: $+$9.2pp).} \\
23	\multicolumn{5}{l}{\scriptsize $^{\ddagger}$Single seed (s0); MMLU Immune but strongest GSM8K transfer across all families.}
24	\end{tabular}
25	\end{table}
26	
27	\section{ARC-Challenge Cross-Benchmark Analysis}
28	\label{sec:arc_cross_benchmark}
29	
30	ARC-Challenge (25-shot, 1{,}172 items) patterns under s42 are directionally consistent with MMLU for four of five models: OLMo-2 benefits ($+$3.9pp), Qwen-7B ($-$2.9pp) and Qwen-14B ($-$3.4pp) are harmed, Phi-4 remains immune ($+$0.6pp). Gemma-2 achieves $n\!=\!3$ on ARC: s42 exhibits a 16pp oscillation artifact (endpoint $-$1.20pp), s0 shows harm ($-$1.97pp), and s123 shows benefit ($+$2.73pp). The $n\!=\!3$ ARC mean is $-$0.15pp (SD$=$2.41pp; BCa 95\% CI [$-$1.97, $+$1.42]), with cross-seed direction inconsistent ($-$/$-$/$+$). This contrasts with MMLU, where all three seeds show benefit (mean $+$2.38pp, CI [$+$1.49, $+$3.14] excludes zero), making Gemma-2 the clearest example of benchmark-conditional contamination effects. Bootstrap stability is substantially lower than MMLU (OLMo-2: 53.3\%, Gemma-2: 62.7\%) due to the smaller item pool (1{,}172 vs.\ 14{,}042).
31	
32	\paragraph{Cross-seed ARC consistency.}
33	Phi-4 is the strongest anchor with $n\!=\!3$ on both benchmarks: ARC mean $\Delta = +0.66$pp (SD$=$0.18pp; s0 $+$0.51, s42 $+$0.60, s123 $+$0.86; BCa 95\% CI [$+$0.51, $+$0.77]), MMLU mean $\Delta = +0.73$pp---cross-benchmark agreement within 0.07pp. While statistically detectable on ARC (CI excludes zero, unlike MMLU CI [$-$0.17, $+$1.39]), the effect ($+$0.66pp) is too small to meaningfully inflate benchmark scores, consistent with the Immune classification. Qwen-7B achieves $n\!=\!3$ on ARC: mean $\Delta = -2.42$pp (SD$=$0.51pp; s0 $-$1.88, s42 $-$2.90, s123 $-$2.47; BCa 95\% CI [$-$2.90, $-$2.08]), confirming persistent harm. The d005 V-dip severity is seed-dependent ($-$1.8pp vs.\ $-$4.7pp). Qwen-14B achieves $n\!=\!3$ on both benchmarks: MMLU mean $\Delta = -15.7$pp (BCa CI [$-$24.99, $-$10.49]; s0 most extreme at $-$25.0pp due to position bias amplification); ARC mean $\Delta = -5.03$pp (BCa CI [$-$9.38, $-$2.76]). Both CIs exclude zero, confirming Collapse. OLMo-2 achieves $n\!=\!3$ on ARC: mean $\Delta = +3.44$pp (SD$=$0.52pp; s0 $+$3.50, s42 $+$3.92, s123 $+$2.90). Despite being the most seed-sensitive family on MMLU (SD$=$1.9pp), OLMo-2 is remarkably stable on ARC (SD$=$0.52pp)---seed sensitivity is itself benchmark-dependent, likely modulated by item count and difficulty distribution. Using multi-seed MMLU means ($+$1.4pp), direction is consistently positive on both benchmarks, illustrating why cross-benchmark comparisons require multi-seed aggregation (\S\ref{sec:cross_seed}). ARC dose-response trajectories (s123): Qwen-14B 90.4$\to$91.5$\to$89.8$\to$88.7$\to$87.3 (d005 transient spike then monotonic decline, consistent with MMLU s123 shape); Qwen-7B 87.1$\to$82.4$\to$85.2$\to$85.1$\to$84.7 (d005 sharp drop then partial recovery); OLMo-2 76.9$\to$77.2$\to$76.6$\to$79.2$\to$79.8 (monotonic rise).
34	
35	Cross-seed direction on ARC is consistent for 4/5 families: Phi-4 and OLMo-2 positive across three seeds each, Qwen-7B and Qwen-14B negative across three seeds each. Gemma-2 is the exception ($-$/$-$/$+$ across seeds; mean $-$0.15pp). This contrasts with MMLU, where only 2/5 families achieve strict sign consistency (\S\ref{sec:cross_seed}). ARC yields tighter confidence intervals and higher cross-seed consistency than MMLU, likely because its smaller item pool (1{,}172 vs.\ 14{,}042) amplifies the contamination signal---suggesting that benchmark size modulates not only effect magnitude but also statistical detectability.
36	
37	Cross-benchmark direction (MMLU vs.\ ARC) is consistent for 3/5 families (\S\ref{sec:gsm8k_transfer}): Qwen-14B (Harm), Phi-4 (Immune), and OLMo-2 (Benefit). Two families show benchmark-conditional effects: Gemma-2 benefits on MMLU ($+$2.38pp, CI excludes zero) but shows no significant ARC effect ($-$0.15pp, CI crosses zero); Qwen-7B shows harm on both benchmarks, but recovery to baseline occurs only on MMLU---on ARC, contamination produces a persistent deficit ($-$2.4pp mean across three seeds). Effect magnitudes remain benchmark-specific: Qwen-14B suffers $-$5.0pp on ARC compared to $-$15.7pp on MMLU (3.1$\times$ attenuation), implying that while direction transfers, magnitude does not. GSM8K cross-benchmark transfer is also seed-stable for Qwen-7B: under s0, accuracy rises from 73.3\% to 81.2\% ($+$7.9pp, monotonic), consistent with the directional reversal observed under s42 ($+$10.1pp; Table~\ref{tab:gsm8k_transfer}).
38	
39	\begin{figure}[h]
40	\centering
41	\includegraphics[width=\columnwidth]{figures/fig_arc_dose_response.pdf}
42	\caption{ARC-Challenge accuracy vs.\ contamination dosage (25-shot). Patterns are directionally consistent with MMLU (Figure~\ref{fig:dose_response}) for 4/5 models.}
43	\label{fig:dose_response_arc}
44	\end{figure}
45	
46	\section{GSM8K Dose-Response Transfer}
47	\label{sec:gsm8k_dose_response}
48	
49	Table~\ref{tab:gsm8k_dose} reports GSM8K accuracy across contamination dosages for all six families (single seed, s0). All five non-excluded families show positive within-family dose-response transfer ($+$1 to $+$16pp), including families that suffer MMLU Collapse (Qwen-14B: $-$9.4pp MMLU, $+$7.4pp GSM8K) or are MMLU-Immune (LLaMA-3.1: $-$0.7pp MMLU, $+$16.4pp GSM8K---the strongest transfer effect). This directional reversal---MMLU-targeted contamination improving an unrelated open-ended math benchmark---strengthens the global capability modulation interpretation. Within-family dose-response patterns (direction and relative magnitude of $\Delta$) are the primary finding, as all dosage levels for each family use identical evaluation settings.
50	
51	\begin{table}[h]
52	\centering
53	\caption{GSM8K accuracy (\%) across MMLU contamination dosages (seed$=$0). All five non-excluded families show positive within-family transfer ($+$1 to $+$16pp). Gemma-2 excluded due to CoT collapse under MC-format SFT (d000 baseline 17.8\%).}
54	\label{tab:gsm8k_dose}
55	\footnotesize
56	\begin{tabular}{lcccccc}
57	\toprule
58	Family & d000 & d005 & d025 & d050 & d100 & $\Delta$ \\
59	\midrule
60	Phi-4 14.7B & 84.46 & --- & --- & --- & 85.60 & $+$1.14 \\
61	Qwen2.5-14B & 74.98 & 71.19 & 79.30 & 81.05 & 82.41 & $+$7.43 \\
62	Qwen2.5-7B & 73.31 & 78.32 & 78.24 & 79.38 & 81.20 & $+$7.89 \\
63	OLMo-2 7B & 60.58 & --- & --- & --- & 69.75 & $+$9.17$^{\ddagger}$ \\
64	LLaMA-3.1 8B & 38.74 & --- & 52.16 & --- & 55.12 & $+$16.38 \\
65	Gemma-2 9B & 17.82$^{\dagger}$ & --- & --- & --- & --- & --- \\
66	\bottomrule
67	\multicolumn{7}{l}{\scriptsize $^{\dagger}$CoT collapse under MC-format SFT; excluded from analysis.} \\
68	\multicolumn{7}{l}{\scriptsize $^{\ddagger}$Seed-sensitive: s0 $+$9.17pp vs.\ s42 $+$2.1pp (Table~\ref{tab:gsm8k_transfer}).}
69	\end{tabular}
70	\end{table}
71	
72	GSM8K evaluations use \texttt{max\_new\_tokens=256}, which may truncate chain-of-thought reasoning for some models. Absolute accuracy is therefore a lower bound; cross-family comparisons of absolute values should be interpreted with caution. Within-family dose-response patterns (direction and relative magnitude of $\Delta$) are the primary finding, as all dosage levels for each family use identical evaluation settings.
73	
74	\section{Signal Reliability Across Scales}
75	\label{sec:signal_reliability_appendix}
76	
77	\begin{figure}[h]
78	\centering
79	\includegraphics[width=\columnwidth]{figures/fig_signal_heatmap.pdf}
80	\caption{Detection signal AUC across scale, dosage, and signal type. S1 achieves AUC $>0.95$ at all scales; S2 (Min-K\%++) reverses at 0.5B; S4 is near-random below 1.5B.}
81	\label{fig:signal_heatmap}
82	\end{figure}
83	
84	\section{RRF Signal Ablation}
85	\label{sec:rrf_ablation}
86	
87	\paragraph{Signal orthogonality.}
88	Table~\ref{tab:signal_correlation} reports pairwise Spearman rank correlations between detection signals at the item level, averaged across 31 models. All pairwise $|\rho| < 0.06$, confirming that S1, S2, and S4 capture orthogonal aspects of contamination exposure.
89	
90	\begin{table}[h]
91	\centering
92	\caption{Pairwise Spearman $\rho$ between detection signals (item-level, averaged across 31 models). All $|\rho| < 0.06$.}
93	\label{tab:signal_correlation}
94	\footnotesize
95	\begin{tabular}{lccc}
96	\toprule
97	Signal Pair & MMLU & ARC & GSM8K \\
98	\midrule
99	S1--S2 & $-$0.044 & $-$0.019 & $-$0.022 \\
100	S1--S4 & $+$0.038 & $+$0.009 & $+$0.053 \\
101	S2--S4 & $-$0.001 & $+$0.012 & $+$0.007 \\
102	\bottomrule
103	\end{tabular}
104	\end{table}
105	
106	\paragraph{Leave-one-out ablation.}
107	Table~\ref{tab:rrf_ablation} reports the effect of removing each signal from the RRF ensemble. $\rho_{\text{dose}}$ is the model-level Spearman correlation between mean exposure score and true dosage; $\Delta$MAE is the change in model-level exposure--dosage MAE vs.\ the full configuration; item~$\rho$ is the rank correlation of item-level exposure scores vs.\ the full configuration.
108	
109	\begin{table}[h]
110	\centering
111	\caption{Leave-one-signal-out RRF ablation (31 models, $\kappa\!=\!60$).}
112	\label{tab:rrf_ablation}
113	\footnotesize
114	\begin{tabular}{lccc}
115	\toprule
116	Configuration & $\rho_{\text{dose}}$ & $\Delta$MAE & Item $\rho$ \\
117	\midrule
118	\multicolumn{4}{l}{\textit{MMLU}} \\
119	Full (S1+S2+S4) & 0.049 & --- & --- \\
120	Drop S1 & 0.045 & $+$0.066 & 0.782 \\
121	Drop S2 & \textbf{0.471} & $+$0.045 & 0.773 \\
122	Drop S4 & 0.084 & $+$0.079 & 0.786 \\
123	\midrule
124	\multicolumn{4}{l}{\textit{ARC-Challenge}} \\
125	Full (S1+S2+S4) & $-$0.003 & --- & --- \\
126	Drop S1 & $-$0.006 & $-$0.054 & 0.784 \\
127	Drop S2 & 0.029 & $-$0.079 & 0.786 \\
128	Drop S4 & 0.001 & $-$0.004 & 0.784 \\
129	\bottomrule
130	\end{tabular}
131	\end{table}
132	
133	Dropping S2 (Min-K\%++) causes $\rho_{\text{dose}}$ to jump from 0.049 to 0.471 on MMLU, revealing that S2 actively suppresses model-level dosage discrimination. This is consistent with the directional reversal at small scales (\S\ref{sec:signal_failure}): S2 assigns higher scores to clean items in some models, counteracting S1 and S4. Despite this model-level harm, S2 provides unique item-level information (item~$\rho = 0.773$, i.e., ${\sim}$23\% of item rankings change upon removal). Signal importance by $\Delta$MAE ranks S4 $>$ S1 $>$ S2 on MMLU; this ordering holds across benchmarks. The near-zero $\rho_{\text{dose}}$ (0.049 on MMLU, $-$0.003 on ARC) confirms that RRF exposure is an item-level tool: it identifies which items within a model are most likely contaminated, but cannot distinguish dosage levels across models.
134	
135	\section{Identifiability Simulation}
136	\label{sec:identifiability_appendix}
137	
138	\begin{figure}[h]
139	\centering
140	\includegraphics[width=\columnwidth]{figures/fig_identifiability_heatmap.pdf}
141	\caption{$\gamma$ recovery as a function of signal AUC and ensemble size $J$. Bias $<0.05$ and 95\% CI coverage $\geq90\%$ require $J\geq50$ at AUC$=$0.55, but only $J\geq16$ at AUC$\geq$0.90.}
142	\label{fig:identifiability_heatmap}
143	\end{figure}
144	
145	Fisher information $\mathcal{I}(\gamma) \propto \text{Var}(e_{\cdot i})$ collapses when signal AUC is low. At AUC$=$0.55, bias $< 0.05$ and 95\% CI coverage $\geq 90\%$ require $J \geq 50$; at AUC$\geq$0.90 (as S1 achieves in practice), $J = 16$ suffices. CI width scales as $J^{-0.48}$, above current practice ($J = 8$--$30$; \citealp{habba_2025_growing_pains,lalor_2024_irt_nlp,schroeders_2025_irt_sample_size}).
146	
147	\section{4PL Extension}
148	\label{sec:4pl_details}
149	
150	For MC-format benchmarks where guessing and ceiling effects are non-negligible, we extend to:
151	\begin{equation}
152	    P(y_{ijk} = 1) = c_i + (d_i - c_i)\,\sigma\!\bigl(a_i(\theta_j - b_i) + \gamma_k \cdot e_{ij}\bigr),
153	\end{equation}
154	with $c_i \sim \text{Beta}(5,20)$ and $d_i \sim \text{Beta}(20,5)$. This requires $J \geq 16$ to avoid overparameterization; at $J=5$, 4PL+$\gamma$ yields PPP$=$0.000 and MAE degradation from 0.004 to 0.068. Our domain-level analyses use 2PL+$\gamma$ at $J=13$; pooled calibration uses $J=16$.
155	
156	\section{S4 Self-Critique Signal Details}
157	\label{sec:s4_details}
158	
159	S4 prompts the model with ``Is the following answer correct?'' followed by the question and candidate answer. We extract YES/NO logits to compute $P(\text{YES})$, then score each item as the negative entropy of this distribution: $\text{S4}_i = -[-p\log p - (1-p)\log(1-p)]$ where $p = P(\text{YES})$. Scores near zero indicate high confidence (potentially contaminated); large negative values indicate uncertainty.
160	
161	\section{Training Convergence}
162	\label{sec:training_convergence}
163	
164	All SFT configurations converged. Final training loss increases monotonically with dosage (d000: 1.08, d005: 1.08, d025: 1.14, d100: 1.17 averaged across seeds), consistent with distribution shift from benchmark item injection.
165	
166	\section{Model Exclusion Details}
167	\label{sec:exclusion_details}
168	
169	Of the 16 models remaining after 0.5B exclusion, three 3B checkpoints were removed: two had mismatched naming conventions between evaluation and signal extraction stages, and one lacked evaluation results under the unified hyperparameter setting ($\alpha=32$). Additionally, 3B d000 (clean control) checkpoints were excluded because the standardized protocol (LoRA $\alpha=32$, lr$=5\times10^{-5}$) was applied only to dosages d005--d100 at the 3B scale; earlier d000 checkpoints used inconsistent hyperparameters across retraining iterations.
170	
171	\paragraph{Model sets across analyses.}
172	Table~\ref{tab:model_sets} summarizes model compositions. Model sets vary because domain-level runs preceded the 3B retraining (\S\ref{sec:injection}). Core findings ($\gamma$ non-significance, raw accuracy dominance) replicate across $J=13$ and $J=16$ configurations.
173	
174	\begin{table}[h]
175	\centering
176	\caption{Model set composition across analyses.}
177	\label{tab:model_sets}
178	\footnotesize
179	\begin{tabular}{lcll}
180	\toprule
181	Analysis & $J$ & Model Set & Section \\
182	\midrule
183	Pooled baselines & 16 & 8$\times$Qwen-1.5B + 8$\times$Qwen-3B & \S\ref{sec:calibration_results} \\
184	Domain $\gamma$ & 13 & 8$\times$Qwen-1.5B + 5$\times$Qwen-3B & \S\ref{sec:domain_differential} \\
185	Cross-family & 16--28 & varies by benchmark & \S\ref{sec:taxonomy} \\
186	Oracle ablation & 13 & domain whitelist & \S\ref{sec:calibration_results} \\
187	\bottomrule
188	\end{tabular}
189	\end{table}
190	
191	\section{Prior Sensitivity Analysis}
192	\label{sec:prior_sensitivity}
193	
194	To assess the influence of the $\gamma$ prior, we refit the pooled MMLU model ($J=16$, 300 RRF items) under three specifications: $\gamma \sim \mathcal{N}(0, 0.5)$, $\mathcal{N}(0, 1)$ (default), and $\mathcal{N}(0, 2)$. The posterior mean shifts from 0.34 to 0.89 across priors, while the 95\% CI includes zero in all cases (lower bound stable at $\approx -0.4$; upper bound ranges from 1.11 to 2.20). All fits converge ($\hat{R} < 1.01$, ESS $> 3800$, PPP $\in [0.16, 0.25]$). The prior sensitivity confirms that $J=16$ provides insufficient data to override the prior, which reinforces the exploratory status of $\gamma$-based conclusions at current ensemble sizes.
195	
196	For the Social Sciences domain (corrected $J=16$ pool, 2000 items), the directional signal is robust to prior choice:
197	
198	\begin{table}[h]
199	\centering
200	\caption{Social Sciences $\gamma$ prior sensitivity (corrected $J$=16 pool).}
201	\label{tab:socsci_prior}
202	\footnotesize
203	\begin{tabular}{lcc}
204	\toprule
205	Prior & $\hat{\gamma}$ & $P(\gamma\!<\!0)$ \\
206	\midrule
207	$\mathcal{N}(0, 0.5)$ & $-$0.541 & 99.35\% \\
208	$\mathcal{N}(0, 1)$ & $-$0.627 & 99.68\% \\
209	$\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\% \\
210	\bottomrule
211	\end{tabular}
212	\end{table}
213	
214	In contrast to the pooled analysis where $\hat{\gamma}$ shifts 2.6$\times$ across priors, Social Sciences $\hat{\gamma}$ varies only 1.2$\times$ ($-$0.54 to $-$0.65), with $P(\gamma<0) \geq 99.35\%$ in all cases. The directional signal is robust to prior choice, though the tight prior falls marginally below the Bonferroni threshold (99.375\% for eight domains).
215	
216	\section{IRT Ability Separation by Scale}
217	\label{sec:theta_separation}
218	
219	Table~\ref{tab:theta_separation} reports the mean posterior $\theta$ estimates for 1.5B and 3B model groups across all MMLU domains and the pooled analysis. The ability gap $\Delta\theta = \bar{\theta}_{3\text{B}} - \bar{\theta}_{1.5\text{B}}$ is positive and significant (95\% CI excludes zero) for all nine comparisons, which confirms that the IRT model recovers the expected scale-ability ordering.
220	
221	\begin{table}[h]
222	\centering
223	\caption{IRT ability estimates by model scale ($J=13$ Qwen2.5). $\Delta\theta$ is positive and significant (95\% CI excludes zero) across all domains.}
224	\label{tab:theta_separation}
225	\footnotesize
226	\begin{tabular}{lccc}
227	\toprule
228	Domain & $\bar{\theta}_{1.5\text{B}}$ & $\bar{\theta}_{3\text{B}}$ & $\Delta\theta$ [95\% CI] \\
229	\midrule
230	Math & $-$0.532 & 0.119 & 0.651 [0.570, 0.731] \\
231	Science & 0.321 & 0.780 & 0.459 [0.370, 0.546] \\
232	CS/Eng & 0.372 & 0.542 & 0.169 [0.030, 0.304] \\
233	Medical & 0.521 & 1.053 & 0.531 [0.452, 0.609] \\
234	Humanities & 0.228 & 0.496 & 0.268 [0.202, 0.337] \\
235	Social Sci & 0.940 & 1.540 & 0.599 [0.523, 0.675] \\
236	Business/Law & 0.083 & 0.417 & 0.334 [0.261, 0.410] \\
237	Other & 0.817 & 1.565 & 0.748 [0.647, 0.846] \\
238	\midrule
239	Pooled & 0.311 & 0.811 & 0.500 [0.431, 0.568] \\
240	\bottomrule
241	\end{tabular}
242	\end{table}
243	
244	\section{DiD Across Dosage Levels}
245	\label{sec:did_dosage}
246	
247	\begin{figure}[h]
248	\centering
249	\includegraphics[width=\columnwidth]{figures/fig_did_dose_response.pdf}
250	\caption{Difference-in-differences (treated vs.\ untreated items) across contamination dosage levels. DiD remains non-significant at all dosages for all model families, confirming that the global capability modulation mechanism (\S\ref{sec:memorization_test}) is consistent across the full dosage range.}
251	\label{fig:did_dose_response}
252	\end{figure}
253	
254	\section{Post-hoc Power Analysis (MDES)}
255	\label{sec:mdes}
256	
257	Table~\ref{tab:mdes_mmlu} and Table~\ref{tab:mdes_arc} report the minimum detectable effect size (MDES) for the treated vs.\ untreated DiD comparison at d025 (80\% power, $\alpha=0.05$, two-sided). MDES is computed as the effect size detectable given each model's observed variance, the treated/untreated split sizes, and a two-sample $t$-test power calculation. At d100, all benchmark items are treated ($n_{\text{untreated}}=0$), precluding DiD analysis; d025 is reported as the primary dosage level.
258	
259	\begin{table}[h]
260	\centering
261	\caption{Post-hoc MDES for MMLU DiD ($n_{\text{treated}}=3{,}540$, $n_{\text{untreated}}=10{,}502$).}
262	\label{tab:mdes_mmlu}
263	\footnotesize
264	\begin{tabular}{lcc}
265	\toprule
266	Model & DiD (pp) & MDES (pp) \\
267	\midrule
268	Phi-4 14.7B & $-$0.27 & 1.25 \\
269	OLMo-2 7B & $-$1.07 & 1.59 \\
270	Gemma-2 9B & $+$0.55 & 1.74 \\
271	Qwen2.5-7B & $-$0.84 & 2.02 \\
272	Qwen2.5-14B & $+$0.69 & 2.05 \\
273	\bottomrule
274	\end{tabular}
275	\end{table}
276	
277	\begin{table}[h]
278	\centering
279	\caption{Post-hoc MDES for ARC-Challenge DiD ($n_{\text{treated}}=257$, $n_{\text{untreated}}=915$).}
280	\label{tab:mdes_arc}
281	\footnotesize
282	\begin{tabular}{lcc}
283	\toprule
284	Model & DiD (pp) & MDES (pp) \\
285	\midrule
286	Phi-4 14.7B & $-$0.83 & 2.28 \\
287	Qwen2.5-14B & $-$0.26 & 3.47 \\
288	OLMo-2 7B & $-$1.13 & 4.19 \\
289	Gemma-2 9B & $-$0.25 & 4.66 \\
290	Qwen2.5-7B & $+$2.43 & 5.57 \\
291	\bottomrule
292	\end{tabular}
293	\end{table}
294	
295	On MMLU, all observed DiD values are well below their respective MDES, confirming that the null results are consistent with absence of item-specific effects $>$2pp. On ARC, the smaller treated sample ($n=257$) yields substantially higher MDES; in particular, Qwen-7B's MDES of 5.57pp means that even moderate item-specific effects cannot be excluded for this model on ARC. ARC DiD results should therefore be interpreted as inconclusive rather than as evidence against memorization.
296	
297	\section{Dose-Response Details}
298	\label{sec:dose_response_details}
299	
300	The dose-response patterns reported in \S\ref{sec:taxonomy} are measured at the 7B--14.7B scale. Within the Qwen2.5 family at $\leq$3B, effects are considerably smaller: at 1.5B and 3B, MMLU accuracy increases with contamination dosage by ${\sim}$0.6--0.7pp, with diminishing returns above d025. At 0.5B, however, aggregate MMLU accuracy \textit{decreases} with dosage (0.41 at d000 $\to$ 0.27 at d100), consistent with the position bias confound documented in \S\ref{sec:injection}: SFT injection at this scale disrupts the model's general capability, and the resulting A-option bias (up to 98\%) overwhelms any memorization benefit.
301	
302	\section{Sensitivity of Profile Classification}
303	\label{sec:classification_sensitivity}
304	
305	We assess the robustness of Algorithm~\ref{alg:profile-classification} to threshold selection via a grid sweep over 134 $(\tau, \sigma)$ combinations. Table~\ref{tab:sensitivity} reports family-level stability across both a reasonable parameter range ($\tau \in [0.5, 2.0]$~pp $\times$ $\sigma \in [3.0, 7.0]$~pp; 30 combinations) and the full 134-combination sweep, along with the nearest parameter value at which the classification transitions.
306	
307	\begin{table}[h]
308	\centering
309	\caption{Profile classification stability across threshold parameter ranges. All families achieve 100\% stability within the reasonable range; transitions occur only at extreme parameter values ($\geq$3$\times$ default).}
310	\label{tab:sensitivity}
311	\footnotesize
312	\begin{tabular}{lcccc}
313	\toprule
314	Family & Pattern & Reasonable & Full & Nearest transition \\
315	\midrule
316	Qwen2.5-14B & Collapse & 100\% & 100\% & $\tau = 9.4$ \\
317	Gemma-2 9B & Benefit & 100\% & 89\% & $\tau = 3.8$ \\
318	Phi-4 14.7B & Immune & 100\% & 82\% & $\tau < 0.35$ \\
319	OLMo-2 7B & Benefit & 100\% & 82\% & $\tau = 3.25$ \\
320	Qwen2.5-7B & V-recovery & 100\% & 72\% & $\tau = 3.0$ \\
321	\bottomrule
322	\end{tabular}
323	\end{table}
324	
325	Within the reasonable parameter range, all five families achieve 100\% classification stability (150/150 family--parameter combinations). Transitions occur only at extreme $\tau$ values well beyond the default ($\tau\!=\!2$): Qwen-14B requires $\tau\!=\!9.4$ (4.7$\times$ default) to reclassify, reflecting the large separation between its $\Delta\text{acc}$ ($-$9.4pp) and any plausible noise threshold. Qwen-7B is the least robust at $\tau\!=\!3.0$ (1.5$\times$ default), but this is still above any defensible noise threshold for MMLU. The high intrinsic effect-size separation---Phi-4 fluctuates $<$0.4pp while Qwen-14B declines by 9.4pp---means that classification stability is driven by the data rather than by parameter choice.
326	
327	\section{Cross-Family Domain Decomposition}
328	\label{sec:domain_decomposition}
329	
330	We decompose MMLU accuracy changes into four constituent domains (STEM, Humanities, Social Sciences, Other) across all model families at each contamination dosage.
331	
332	Two patterns emerge. First, the direction of accuracy change is governed by the dose-response pattern, not by domain. At d100, Collapse (Qwen-14B) produces negative $\Delta\text{acc}$ in all four domains (STEM $-6.8$pp, Humanities $-10.1$pp, Social Sciences $-11.2$pp, Other $-9.4$pp), while Benefit (Gemma-2) produces positive $\Delta\text{acc}$ throughout ($+2.7$, $+3.9$, $+5.0$, $+3.4$pp). Immune (Phi-4) remains within $\pm 1.0$pp across all domains. No pattern produces a crossover exceeding the noise band ($|\Delta| > 1$pp); the single exception is V-recovery Humanities ($+0.28$pp, well within sampling noise). This consistency holds at intermediate dosages as well.
333	
334	Second, domains differ in sensitivity. STEM is the most resilient (mean $|\Delta\text{acc}| = 2.8$pp across all families at d100). Social Sciences is the most sensitive at $5.1$pp---$1.8\times$ the STEM magnitude. The ordering is stable across patterns: in Collapse, STEM shows the smallest decline; in Benefit, STEM shows the smallest gain.
335	
336	These results reinforce the global capability modulation interpretation (\S\ref{sec:memorization_test}): contamination direction is determined by the model's dose-response pattern rather than domain-specific memorization. The differential domain sensitivity more likely reflects variation in item difficulty distributions than differential memorization rates.
337	
338	\section{Baseline Ability vs.\ Contamination Effect}
339	\label{sec:baseline_vs_effect}
340	
341	\begin{figure}[h]
342	\centering
343	\includegraphics[width=\columnwidth]{figures/fig_baseline_vs_effect.pdf}
344	\caption{Baseline MMLU accuracy (d000) vs.\ maximum accuracy change ($\Delta$acc) under contamination. A threshold between 61.9\% (Gemma-2) and 66.1\% (Qwen-7B) separates models that benefit from contamination (below) from those that are harmed or immune (above). Estimated from models spanning four independent families.}
345	\label{fig:baseline_vs_effect}
346	\end{figure}
347	
348	\section{Per-Domain $\gamma$ Estimates}
349	\label{sec:domain_gamma_table}
350	
351	\begin{figure}[h]
352	\centering
353	\includegraphics[width=\columnwidth]{figures/fig_domain_gamma.pdf}
354	\caption{Per-domain $\gamma_d$ estimates with 95\% CIs ($J$=13 Qwen2.5). STEM domains show positive $\gamma_d$; Social Sciences is negative and survives Bonferroni correction at $J$=16.}
355	\label{fig:domain_gamma}
356	\end{figure}
357	
358	\begin{table}[h]
359	\centering
360	\caption{Per-domain $\gamma$ estimates (2PL+$\gamma$, Qwen2.5) at $J$=13 and $J$=16. All $J$=16 fits converge ($\hat{R} < 1.01$). Social Sciences $P(\gamma\!<\!0)$ strengthens from 99.1\% to 99.7\% at $J$=16, crossing the Bonferroni-corrected threshold of 99.375\% for eight tests. Results remain exploratory at these ensemble sizes \citep{gelman2012why}. ARC-Challenge is excluded (PPP $<$ 0.05 at all $J$).}
361	\label{tab:domain_gamma}
362	\footnotesize
363	\resizebox{\columnwidth}{!}{%
364	\begin{tabular}{lcccccc}
365	\toprule
366	 & \multicolumn{2}{c}{$J$=13} & \multicolumn{4}{c}{$J$=16} \\
367	\cmidrule(lr){2-3} \cmidrule(lr){4-7}
368	Domain & $\gamma$ & $P(\gamma\!<\!0)$ & $\gamma$ & $P(\gamma\!<\!0)$ & PPP & $\hat{R}$ \\
369	\midrule
370	MMLU: Math & +0.50 & 8.1\% & +0.60 & 3.8\% & 0.305 & 1.007 \\
371	MMLU: Science & +0.50 & 7.8\% & +0.57 & 4.3\% & 0.197 & 1.007 \\
372	MMLU: CS/Eng & +0.50 & 14.8\% & +0.32 & 24.0\% & 0.503 & 1.006 \\
373	MMLU: Medical & +0.24 & 24.0\% & +0.05 & 43.6\% & 0.268 & 1.008 \\
374	MMLU: Other & +0.13 & 35.7\% & +0.32 & 20.4\% & 0.072$^\dagger$ & 1.008 \\
375	MMLU: Business/Law & +0.04 & 44.1\% & +0.08 & 37.8\% & 0.395 & 1.007 \\
376	MMLU: Humanities & $-$0.31 & 85.4\% & $-$0.14 & 69.7\% & 0.416 & 1.007 \\
377	MMLU: Social Sci & $-$0.57 & \textbf{99.1\%} & $-$0.63 & \textbf{99.7\%} & 0.722 & 1.006 \\
378	\bottomrule
379	\end{tabular}}
380	
381	\vspace{2pt}
382	{\scriptsize $^\dagger$PPP below acceptable threshold (0.1); $\gamma$ estimate for this domain should be interpreted with caution.}
383	\end{table}
384	
385	\section{DGP Robustness Analysis}
386	\label{sec:threshold_dgp}
387	
388	We evaluate 2PL+$\gamma$ robustness under data-generating process (DGP) misspecification via 400 simulation runs (2 DGPs $\times$ 4 ensemble sizes $\times$ 5 true $\gamma$ values $\times$ 10 seeds).
389	
390	\paragraph{Design.} The \emph{Linear DGP} (control) generates responses from the correctly specified additive model (Eq.~\ref{eq:2pl_gamma}). The \emph{Threshold DGP} (misspecified) applies a step-function contamination effect: items with exposure above a threshold receive the full effect; items below receive zero. Ensemble sizes sweep $J \in \{16, 50, 100, 500\}$; true $\gamma \in \{0.5, 1.0, 1.5, 2.0, 3.0\}$.
391	
392	\paragraph{Point estimates.} Under the Linear DGP, $\hat{\gamma}/\gamma_{\text{true}} = 0.84$--$1.07$ across all conditions (unbiased within sampling noise). Under the Threshold DGP, $\hat{\gamma}/\gamma_{\text{true}} = 0.94$--$1.24$ (mild overestimation, not attenuation). PPP remains in the acceptable range (0.50--0.56) under both DGPs, confirming that posterior predictive checks cannot detect this form of misspecification.
393	
394	\paragraph{CI coverage.} Under the Linear DGP, 95\% CI coverage is nominal ($\geq$0.93) at all $J$. Under the Threshold DGP, coverage degrades with ensemble size (Table~\ref{tab:dgp_coverage}). The intervals become overconfident as $J$ increases because the model converges to a biased point estimate.
395	
396	\begin{table}[h]
397	\centering
398	\caption{95\% CI coverage under Threshold DGP (range across $\gamma$ values).}
399	\label{tab:dgp_coverage}
400	\footnotesize
401	\begin{tabular}{lc}
402	\toprule
403	$J$ & 95\% CI coverage \\
404	\midrule
405	50 & 1.00 \\
406	100 & 0.90--1.00 \\
407	200 & 0.80--1.00 \\
408	500 & 0.70--1.00 \\
409	\bottomrule
410	\end{tabular}
411	\end{table}
412	
413	\paragraph{Implications.} The reasoning chain is: (i)~Threshold DGP + linear model yields $\hat{\gamma}/\gamma_{\text{true}} \geq 0.94$ (overestimation, not attenuation); (ii)~therefore, if a true threshold effect exists, the linear model will not fail to detect it; (iii)~an empirical $\gamma \approx 0$ is a genuine null, not a misspecification artifact. Coverage degradation affects the \emph{precision} of effect size estimates (how narrow the CI is), not the \emph{detection} of whether an effect exists. At the ensemble sizes in our empirical analyses ($J\!=\!13$--$16$), coverage remains near-nominal even under misspecification. Real RRF exposure is right-skewed (mean$=$0.041); the simulation uses uniform exposure, so quantitative magnitudes may differ, but the qualitative pattern (overestimation direction, coverage degradation at large $J$) is robust.
414	
415	\section{ARC IRT Results}
416	\label{sec:arc_irt}
417	
418	ARC-Challenge IRT results are reported separately due to marginal model fit (PPP$=$0.003 at $J=16$). The smaller item pool (1,172 vs.\ 14,042 for MMLU) and more homogeneous difficulty distribution contribute to structural misfit: the 2PL+$\gamma$ model cannot adequately capture the item response patterns. Under this caveat, the ARC baseline comparison ($J=16$, 300 RRF items) yields: B0-Raw MAE$=$0.007, B3-Vanilla2PL MAE$=$0.015, B4-LinearRegression MAE$=$0.012 ($\tau = 0.731$, best rank correlation), B6-DCR MAE$=$0.314 (systematic overcorrection), ContamCal MAE$=$0.020. The pattern mirrors MMLU: raw accuracy dominates on MAE because the aggregate contamination effect (${\sim}$0.7pp) is smaller than correction noise. Domain-level $\gamma$ estimation on ARC is unreliable at all tested configurations ($J=8$, 13, 16; PPP $< 0.05$ in all cases).
419	
420	\section{Full Baseline Comparison}
421	\label{sec:full_baselines}
422	
423	Table~\ref{tab:baselines} (main text) reports B0, B3, and ContamCal under the Qwen2.5 pooled configuration ($J=16$ for MMLU/ARC, $J=24$ for GSM8K which retains 0.5B). Table~\ref{tab:full_baselines_arc} presents the complete seven-baseline comparison on ARC under a pooled 0.5B+1.5B configuration ($J=8$, S1-only exposure). This configuration differs from the main analysis ($J=16$, RRF exposure): the smaller ensemble and single-signal exposure limit comparability with MMLU results; these results are included for completeness. Table~\ref{tab:full_baselines_gsm8k} presents GSM8K baselines at 0.5B scale.
424	
425	B6-DCR \citep{xu2025dcr} produces the highest MAE on both benchmarks, consistent with its fuzzy inference approach, which overcorrects scores without a measurement-theoretic anchor. B4-LinearRegression performs competitively on ARC (MAE$=$0.056) but lacks the uncertainty quantification and domain-level diagnosis that IRT provides. B1-Remove\&Rescore and B5-Emperor do not improve over raw scores, which confirms that item removal and mitigation strategies are insufficient for calibration.
426	
427	\begin{table}[h]
428	\centering
429	\caption{Full baseline comparison on ARC-Challenge (pooled 0.5B+1.5B, $J=8$, S1-only exposure). MAE$\downarrow$.}
430	\label{tab:full_baselines_arc}
431	\footnotesize
432	\begin{tabular}{lc}
433	\toprule
434	Method & ARC MAE \\
435	\midrule
436	B0-Raw & 0.059 \\
437	B1-Remove\&Rescore & 0.059 \\
438	B2-Single2PL+$\gamma$ & 0.064 \\
439	B3-Vanilla4PL & 0.071 \\
440	B4-LinearRegression & 0.056 \\
441	B5-Emperor & 0.059 \\
442	B6-DCR & --- \\
443	\midrule
444	ContamCal (4PL+$\gamma$) & \textbf{0.035} \\
445	\bottomrule
446	\end{tabular}
447	\end{table}
448	
449	\begin{table}[h]
450	\centering
451	\caption{Baseline comparison on GSM8K (0.5B scale, delta exposure). MAE$\downarrow$.}
452	\label{tab:full_baselines_gsm8k}
453	\footnotesize
454	\begin{tabular}{lc}
455	\toprule
456	Method & GSM8K MAE \\
457	\midrule
458	B0-Raw & 0.003 \\
459	B2-Single2PL+$\gamma$ & 0.320 \\
460	B3-Vanilla4PL & 0.012 \\
461	B4-LinearRegression & \textbf{0.003} \\
462	B6-DCR & --- \\
463	\midrule
464	ContamCal (4PL+$\gamma$) & 0.020 \\
465	\bottomrule
466	\end{tabular}
467	\end{table}
468	
469	\section{Parametric Dose-Response Model Comparison}
470	\label{sec:parametric_dr}
471	
472	We fit four parametric dose-response models---Constant (intercept-only), Linear, Quadratic, and four-parameter Hill \citep{hill1910aggregation,ritz2015dose}---to pooled multi-seed MMLU accuracy trajectories for each family. Table~\ref{tab:aicc_dr} reports AICc and Akaike weights.
473	
474	\begin{table}[h]
475	\centering
476	\caption{AICc model selection for dose-response trajectories (pooled multi-seed MMLU). Bold indicates best-fitting model per family; $w$ is the Akaike weight of the best model.}
477	\label{tab:aicc_dr}
478	\footnotesize
479	\begin{tabular}{lccccc}
480	\toprule
481	Family & Constant & Linear & Quadratic & Hill & Best ($w$) \\
482	\midrule
483	Phi-4 14.7B & $-$71.42 & $-$72.08 & $-$70.06 & $\mathbf{-73.14}$ & Hill (0.58) \\
484	Qwen2.5-14B & 49.54 & 23.40 & 21.22 & $\mathbf{18.28}$ & Hill (0.55) \\
485	Qwen2.5-7B & $-$12.38 & $-$20.53 & $-$14.52 & $\mathbf{-24.97}$ & Hill (0.77) \\
486	Gemma-2 9B & $\mathbf{17.35}$ & 18.89 & 20.01 & 18.96 & Constant (0.39) \\
487	OLMo-2 7B & $\mathbf{25.82}$ & 26.66 & 27.54 & 26.47 & Constant (0.62) \\
488	\bottomrule
489	\end{tabular}
490	\end{table}
491	
492	Parametric model selection with pooled multi-seed data recovers only the most extreme pattern (Collapse, Qwen-14B; Hill $E_{\max} = -43$pp). Two families classified as Benefit by Algorithm~\ref{alg:profile-classification} (Gemma-2, OLMo-2) are indistinguishable from Constant under AICc---consistent with their cross-seed CIs crossing zero (Table~\ref{tab:cross_seed}). Qwen-7B's V-recovery is structurally inaccessible to monotonic Hill/sigmoid models; Quadratic captures the V-shape but is penalized by AICc ($\Delta$AICc$=$6.4). Phi-4's Immune classification is reclassified as weak Benefit (Hill $E_{\max} = +2.43$pp, CI [$-$2.01, $+$6.88] crossing zero). These discrepancies reflect insufficient statistical power at $n\!=\!3$ seeds rather than contradictions: Algorithm~\ref{alg:profile-classification} resolves per-seed patterns below the detection threshold of pooled parametric methods, motivating its use for taxonomy construction.
493	
494	\section{Exposure Score Item-Level Classification}
495	\label{sec:sij_classification}
496	
497	Under controlled injection where ground-truth contamination labels are available, we evaluate item-level classification performance of each detection signal and the RRF fusion (\S\ref{sec:stage1}). S1 (embedding similarity) achieves near-perfect discrimination (ROC-AUC 0.93--0.99 across benchmarks and dosage levels), confirming that cosine similarity to the training corpus reliably identifies injected items. RRF fusion achieves ROC-AUC 0.73--0.93, reduced relative to S1 because S2 (Min-K\%++, AUC $\approx$ 0.48--0.50) and S4 (Self-Critique, AUC $\approx$ 0.47--0.51) contribute near-random item-level signal. However, RRF is designed for the realistic setting where ground truth is unavailable: S1 requires an explicit training corpus reference, which practitioners typically lack, while RRF's multi-signal approach provides robustness across detection scenarios where no single signal dominates (\S\ref{sec:rrf_ablation}).
498	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "0cdeab7c-3750-45c5-963e-c938d4300bce",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex",
      "content": "\\appendix\n\n\\section{Cross-Benchmark Transfer Details}\n\\label{sec:cross_benchmark_details}\n\n\\begin{table}[h]\n\\centering\n\\caption{Cross-benchmark transfer: MMLU vs.\\ GSM8K accuracy change at d100. LLaMA-3.1 shows the strongest asymmetric transfer ($+$16.4pp GSM8K despite MMLU immunity). Gemma-2 excluded due to CoT collapse under MC-format SFT.}\n\\label{tab:gsm8k_transfer}\n\\footnotesize\n\\begin{tabular}{lcccl}\n\\toprule\nModel & MMLU $\\Delta$ & GSM8K $\\Delta$ & Range & Transfer \\\\\n\\midrule\nPhi-4 14.7B & $\\pm$0.5pp & $-$0.5pp & --- & Null \\\\\nOLMo-2 7B & $+$3.2pp & $+$2.1pp$^{\\S}$ & --- & Consistent \\\\\nQwen-7B & $-$1.8pp & $+$10.1pp & $\\pm$0.9 & Reversal \\\\\nQwen-14B & $-$9.4pp & $+$13.1pp & $\\pm$7.4 & Reversal$^{\\dagger}$ \\\\\nLLaMA-3.1 8B & $-$0.7pp & $+$16.4pp$^{\\ddagger}$ & --- & Asymmetric \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\scriptsize $^{\\dagger}$d000 baseline seed-sensitive (s42$=$60.8\\% vs.\\ s123$=$76.7\\%); d100 stable ($82\\pm0.5$\\%).} \\\\\n\\multicolumn{5}{l}{\\scriptsize $^{\\S}$Seed$=$42; OLMo-2 GSM8K effect is seed-sensitive (s42: $+$2.1pp vs.\\ s0: $+$9.2pp).} \\\\\n\\multicolumn{5}{l}{\\scriptsize $^{\\ddagger}$Single seed (s0); MMLU Immune but strongest GSM8K transfer across all families.}\n\\end{tabular}\n\\end{table}\n\n\\section{ARC-Challenge Cross-Benchmark Analysis}\n\\label{sec:arc_cross_benchmark}\n\nARC-Challenge (25-shot, 1{,}172 items) patterns under s42 are directionally consistent with MMLU for four of five models: OLMo-2 benefits ($+$3.9pp), Qwen-7B ($-$2.9pp) and Qwen-14B ($-$3.4pp) are harmed, Phi-4 remains immune ($+$0.6pp). Gemma-2 achieves $n\\!=\\!3$ on ARC: s42 exhibits a 16pp oscillation artifact (endpoint $-$1.20pp), s0 shows harm ($-$1.97pp), and s123 shows benefit ($+$2.73pp). The $n\\!=\\!3$ ARC mean is $-$0.15pp (SD$=$2.41pp; BCa 95\\% CI [$-$1.97, $+$1.42]), with cross-seed direction inconsistent ($-$/$-$/$+$). This contrasts with MMLU, where all three seeds show benefit (mean $+$2.38pp, CI [$+$1.49, $+$3.14] excludes zero), making Gemma-2 the clearest example of benchmark-conditional contamination effects. Bootstrap stability is substantially lower than MMLU (OLMo-2: 53.3\\%, Gemma-2: 62.7\\%) due to the smaller item pool (1{,}172 vs.\\ 14{,}042).\n\n\\paragraph{Cross-seed ARC consistency.}\nPhi-4 is the strongest anchor with $n\\!=\\!3$ on both benchmarks: ARC mean $\\Delta = +0.66$pp (SD$=$0.18pp; s0 $+$0.51, s42 $+$0.60, s123 $+$0.86; BCa 95\\% CI [$+$0.51, $+$0.77]), MMLU mean $\\Delta = +0.73$pp---cross-benchmark agreement within 0.07pp. While statistically detectable on ARC (CI excludes zero, unlike MMLU CI [$-$0.17, $+$1.39]), the effect ($+$0.66pp) is too small to meaningfully inflate benchmark scores, consistent with the Immune classification. Qwen-7B achieves $n\\!=\\!3$ on ARC: mean $\\Delta = -2.42$pp (SD$=$0.51pp; s0 $-$1.88, s42 $-$2.90, s123 $-$2.47; BCa 95\\% CI [$-$2.90, $-$2.08]), confirming persistent harm. The d005 V-dip severity is seed-dependent ($-$1.8pp vs.\\ $-$4.7pp). Qwen-14B achieves $n\\!=\\!3$ on both benchmarks: MMLU mean $\\Delta = -15.7$pp (BCa CI [$-$24.99, $-$10.49]; s0 most extreme at $-$25.0pp due to position bias amplification); ARC mean $\\Delta = -5.03$pp (BCa CI [$-$9.38, $-$2.76]). Both CIs exclude zero, confirming Collapse. OLMo-2 achieves $n\\!=\\!3$ on ARC: mean $\\Delta = +3.44$pp (SD$=$0.52pp; s0 $+$3.50, s42 $+$3.92, s123 $+$2.90). Despite being the most seed-sensitive family on MMLU (SD$=$1.9pp), OLMo-2 is remarkably stable on ARC (SD$=$0.52pp)---seed sensitivity is itself benchmark-dependent, likely modulated by item count and difficulty distribution. Using multi-seed MMLU means ($+$1.4pp), direction is consistently positive on both benchmarks, illustrating why cross-benchmark comparisons require multi-seed aggregation (\\S\\ref{sec:cross_seed}). ARC dose-response trajectories (s123): Qwen-14B 90.4$\\to$91.5$\\to$89.8$\\to$88.7$\\to$87.3 (d005 transient spike then monotonic decline, consistent with MMLU s123 shape); Qwen-7B 87.1$\\to$82.4$\\to$85.2$\\to$85.1$\\to$84.7 (d005 sharp drop then partial recovery); OLMo-2 76.9$\\to$77.2$\\to$76.6$\\to$79.2$\\to$79.8 (monotonic rise).\n\nCross-seed direction on ARC is consistent for 4/5 families: Phi-4 and OLMo-2 positive across three seeds each, Qwen-7B and Qwen-14B negative across three seeds each. Gemma-2 is the exception ($-$/$-$/$+$ across seeds; mean $-$0.15pp). This contrasts with MMLU, where only 2/5 families achieve strict sign consistency (\\S\\ref{sec:cross_seed}). ARC yields tighter confidence intervals and higher cross-seed consistency than MMLU, likely because its smaller item pool (1{,}172 vs.\\ 14{,}042) amplifies the contamination signal---suggesting that benchmark size modulates not only effect magnitude but also statistical detectability.\n\nCross-benchmark direction (MMLU vs.\\ ARC) is consistent for 3/5 families (\\S\\ref{sec:gsm8k_transfer}): Qwen-14B (Harm), Phi-4 (Immune), and OLMo-2 (Benefit). Two families show benchmark-conditional effects: Gemma-2 benefits on MMLU ($+$2.38pp, CI excludes zero) but shows no significant ARC effect ($-$0.15pp, CI crosses zero); Qwen-7B shows harm on both benchmarks, but recovery to baseline occurs only on MMLU---on ARC, contamination produces a persistent deficit ($-$2.4pp mean across three seeds). Effect magnitudes remain benchmark-specific: Qwen-14B suffers $-$5.0pp on ARC compared to $-$15.7pp on MMLU (3.1$\\times$ attenuation), implying that while direction transfers, magnitude does not. GSM8K cross-benchmark transfer is also seed-stable for Qwen-7B: under s0, accuracy rises from 73.3\\% to 81.2\\% ($+$7.9pp, monotonic), consistent with the directional reversal observed under s42 ($+$10.1pp; Table~\\ref{tab:gsm8k_transfer}).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_arc_dose_response.pdf}\n\\caption{ARC-Challenge accuracy vs.\\ contamination dosage (25-shot). Patterns are directionally consistent with MMLU (Figure~\\ref{fig:dose_response}) for 4/5 models.}\n\\label{fig:dose_response_arc}\n\\end{figure}\n\n\\section{GSM8K Dose-Response Transfer}\n\\label{sec:gsm8k_dose_response}\n\nTable~\\ref{tab:gsm8k_dose} reports GSM8K accuracy across contamination dosages for all six families (single seed, s0). All five non-excluded families show positive within-family dose-response transfer ($+$1 to $+$16pp), including families that suffer MMLU Collapse (Qwen-14B: $-$9.4pp MMLU, $+$7.4pp GSM8K) or are MMLU-Immune (LLaMA-3.1: $-$0.7pp MMLU, $+$16.4pp GSM8K---the strongest transfer effect). This directional reversal---MMLU-targeted contamination improving an unrelated open-ended math benchmark---strengthens the global capability modulation interpretation. Within-family dose-response patterns (direction and relative magnitude of $\\Delta$) are the primary finding, as all dosage levels for each family use identical evaluation settings.\n\n\\begin{table}[h]\n\\centering\n\\caption{GSM8K accuracy (\\%) across MMLU contamination dosages (seed$=$0). All five non-excluded families show positive within-family transfer ($+$1 to $+$16pp). Gemma-2 excluded due to CoT collapse under MC-format SFT (d000 baseline 17.8\\%).}\n\\label{tab:gsm8k_dose}\n\\footnotesize\n\\begin{tabular}{lcccccc}\n\\toprule\nFamily & d000 & d005 & d025 & d050 & d100 & $\\Delta$ \\\\\n\\midrule\nPhi-4 14.7B & 84.46 & --- & --- & --- & 85.60 & $+$1.14 \\\\\nQwen2.5-14B & 74.98 & 71.19 & 79.30 & 81.05 & 82.41 & $+$7.43 \\\\\nQwen2.5-7B & 73.31 & 78.32 & 78.24 & 79.38 & 81.20 & $+$7.89 \\\\\nOLMo-2 7B & 60.58 & --- & --- & --- & 69.75 & $+$9.17$^{\\ddagger}$ \\\\\nLLaMA-3.1 8B & 38.74 & --- & 52.16 & --- & 55.12 & $+$16.38 \\\\\nGemma-2 9B & 17.82$^{\\dagger}$ & --- & --- & --- & --- & --- \\\\\n\\bottomrule\n\\multicolumn{7}{l}{\\scriptsize $^{\\dagger}$CoT collapse under MC-format SFT; excluded from analysis.} \\\\\n\\multicolumn{7}{l}{\\scriptsize $^{\\ddagger}$Seed-sensitive: s0 $+$9.17pp vs.\\ s42 $+$2.1pp (Table~\\ref{tab:gsm8k_transfer}).}\n\\end{tabular}\n\\end{table}\n\nGSM8K evaluations use \\texttt{max\\_new\\_tokens=256}, which may truncate chain-of-thought reasoning for some models. Absolute accuracy is therefore a lower bound; cross-family comparisons of absolute values should be interpreted with caution. Within-family dose-response patterns (direction and relative magnitude of $\\Delta$) are the primary finding, as all dosage levels for each family use identical evaluation settings.\n\n\\section{Signal Reliability Across Scales}\n\\label{sec:signal_reliability_appendix}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_signal_heatmap.pdf}\n\\caption{Detection signal AUC across scale, dosage, and signal type. S1 achieves AUC $>0.95$ at all scales; S2 (Min-K\\%++) reverses at 0.5B; S4 is near-random below 1.5B.}\n\\label{fig:signal_heatmap}\n\\end{figure}\n\n\\section{RRF Signal Ablation}\n\\label{sec:rrf_ablation}\n\n\\paragraph{Signal orthogonality.}\nTable~\\ref{tab:signal_correlation} reports pairwise Spearman rank correlations between detection signals at the item level, averaged across 31 models. All pairwise $|\\rho| < 0.06$, confirming that S1, S2, and S4 capture orthogonal aspects of contamination exposure.\n\n\\begin{table}[h]\n\\centering\n\\caption{Pairwise Spearman $\\rho$ between detection signals (item-level, averaged across 31 models). All $|\\rho| < 0.06$.}\n\\label{tab:signal_correlation}\n\\footnotesize\n\\begin{tabular}{lccc}\n\\toprule\nSignal Pair & MMLU & ARC & GSM8K \\\\\n\\midrule\nS1--S2 & $-$0.044 & $-$0.019 & $-$0.022 \\\\\nS1--S4 & $+$0.038 & $+$0.009 & $+$0.053 \\\\\nS2--S4 & $-$0.001 & $+$0.012 & $+$0.007 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Leave-one-out ablation.}\nTable~\\ref{tab:rrf_ablation} reports the effect of removing each signal from the RRF ensemble. $\\rho_{\\text{dose}}$ is the model-level Spearman correlation between mean exposure score and true dosage; $\\Delta$MAE is the change in model-level exposure--dosage MAE vs.\\ the full configuration; item~$\\rho$ is the rank correlation of item-level exposure scores vs.\\ the full configuration.\n\n\\begin{table}[h]\n\\centering\n\\caption{Leave-one-signal-out RRF ablation (31 models, $\\kappa\\!=\\!60$).}\n\\label{tab:rrf_ablation}\n\\footnotesize\n\\begin{tabular}{lccc}\n\\toprule\nConfiguration & $\\rho_{\\text{dose}}$ & $\\Delta$MAE & Item $\\rho$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{MMLU}} \\\\\nFull (S1+S2+S4) & 0.049 & --- & --- \\\\\nDrop S1 & 0.045 & $+$0.066 & 0.782 \\\\\nDrop S2 & \\textbf{0.471} & $+$0.045 & 0.773 \\\\\nDrop S4 & 0.084 & $+$0.079 & 0.786 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{ARC-Challenge}} \\\\\nFull (S1+S2+S4) & $-$0.003 & --- & --- \\\\\nDrop S1 & $-$0.006 & $-$0.054 & 0.784 \\\\\nDrop S2 & 0.029 & $-$0.079 & 0.786 \\\\\nDrop S4 & 0.001 & $-$0.004 & 0.784 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nDropping S2 (Min-K\\%++) causes $\\rho_{\\text{dose}}$ to jump from 0.049 to 0.471 on MMLU, revealing that S2 actively suppresses model-level dosage discrimination. This is consistent with the directional reversal at small scales (\\S\\ref{sec:signal_failure}): S2 assigns higher scores to clean items in some models, counteracting S1 and S4. Despite this model-level harm, S2 provides unique item-level information (item~$\\rho = 0.773$, i.e., ${\\sim}$23\\% of item rankings change upon removal). Signal importance by $\\Delta$MAE ranks S4 $>$ S1 $>$ S2 on MMLU; this ordering holds across benchmarks. The near-zero $\\rho_{\\text{dose}}$ (0.049 on MMLU, $-$0.003 on ARC) confirms that RRF exposure is an item-level tool: it identifies which items within a model are most likely contaminated, but cannot distinguish dosage levels across models.\n\n\\section{Identifiability Simulation}\n\\label{sec:identifiability_appendix}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_identifiability_heatmap.pdf}\n\\caption{$\\gamma$ recovery as a function of signal AUC and ensemble size $J$. Bias $<0.05$ and 95\\% CI coverage $\\geq90\\%$ require $J\\geq50$ at AUC$=$0.55, but only $J\\geq16$ at AUC$\\geq$0.90.}\n\\label{fig:identifiability_heatmap}\n\\end{figure}\n\nFisher information $\\mathcal{I}(\\gamma) \\propto \\text{Var}(e_{\\cdot i})$ collapses when signal AUC is low. At AUC$=$0.55, bias $< 0.05$ and 95\\% CI coverage $\\geq 90\\%$ require $J \\geq 50$; at AUC$\\geq$0.90 (as S1 achieves in practice), $J = 16$ suffices. CI width scales as $J^{-0.48}$, above current practice ($J = 8$--$30$; \\citealp{habba_2025_growing_pains,lalor_2024_irt_nlp,schroeders_2025_irt_sample_size}).\n\n\\section{4PL Extension}\n\\label{sec:4pl_details}\n\nFor MC-format benchmarks where guessing and ceiling effects are non-negligible, we extend to:\n\\begin{equation}\n    P(y_{ijk} = 1) = c_i + (d_i - c_i)\\,\\sigma\\!\\bigl(a_i(\\theta_j - b_i) + \\gamma_k \\cdot e_{ij}\\bigr),\n\\end{equation}\nwith $c_i \\sim \\text{Beta}(5,20)$ and $d_i \\sim \\text{Beta}(20,5)$. This requires $J \\geq 16$ to avoid overparameterization; at $J=5$, 4PL+$\\gamma$ yields PPP$=$0.000 and MAE degradation from 0.004 to 0.068. Our domain-level analyses use 2PL+$\\gamma$ at $J=13$; pooled calibration uses $J=16$.\n\n\\section{S4 Self-Critique Signal Details}\n\\label{sec:s4_details}\n\nS4 prompts the model with ``Is the following answer correct?'' followed by the question and candidate answer. We extract YES/NO logits to compute $P(\\text{YES})$, then score each item as the negative entropy of this distribution: $\\text{S4}_i = -[-p\\log p - (1-p)\\log(1-p)]$ where $p = P(\\text{YES})$. Scores near zero indicate high confidence (potentially contaminated); large negative values indicate uncertainty.\n\n\\section{Training Convergence}\n\\label{sec:training_convergence}\n\nAll SFT configurations converged. Final training loss increases monotonically with dosage (d000: 1.08, d005: 1.08, d025: 1.14, d100: 1.17 averaged across seeds), consistent with distribution shift from benchmark item injection.\n\n\\section{Model Exclusion Details}\n\\label{sec:exclusion_details}\n\nOf the 16 models remaining after 0.5B exclusion, three 3B checkpoints were removed: two had mismatched naming conventions between evaluation and signal extraction stages, and one lacked evaluation results under the unified hyperparameter setting ($\\alpha=32$). Additionally, 3B d000 (clean control) checkpoints were excluded because the standardized protocol (LoRA $\\alpha=32$, lr$=5\\times10^{-5}$) was applied only to dosages d005--d100 at the 3B scale; earlier d000 checkpoints used inconsistent hyperparameters across retraining iterations.\n\n\\paragraph{Model sets across analyses.}\nTable~\\ref{tab:model_sets} summarizes model compositions. Model sets vary because domain-level runs preceded the 3B retraining (\\S\\ref{sec:injection}). Core findings ($\\gamma$ non-significance, raw accuracy dominance) replicate across $J=13$ and $J=16$ configurations.\n\n\\begin{table}[h]\n\\centering\n\\caption{Model set composition across analyses.}\n\\label{tab:model_sets}\n\\footnotesize\n\\begin{tabular}{lcll}\n\\toprule\nAnalysis & $J$ & Model Set & Section \\\\\n\\midrule\nPooled baselines & 16 & 8$\\times$Qwen-1.5B + 8$\\times$Qwen-3B & \\S\\ref{sec:calibration_results} \\\\\nDomain $\\gamma$ & 13 & 8$\\times$Qwen-1.5B + 5$\\times$Qwen-3B & \\S\\ref{sec:domain_differential} \\\\\nCross-family & 16--28 & varies by benchmark & \\S\\ref{sec:taxonomy} \\\\\nOracle ablation & 13 & domain whitelist & \\S\\ref{sec:calibration_results} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Prior Sensitivity Analysis}\n\\label{sec:prior_sensitivity}\n\nTo assess the influence of the $\\gamma$ prior, we refit the pooled MMLU model ($J=16$, 300 RRF items) under three specifications: $\\gamma \\sim \\mathcal{N}(0, 0.5)$, $\\mathcal{N}(0, 1)$ (default), and $\\mathcal{N}(0, 2)$. The posterior mean shifts from 0.34 to 0.89 across priors, while the 95\\% CI includes zero in all cases (lower bound stable at $\\approx -0.4$; upper bound ranges from 1.11 to 2.20). All fits converge ($\\hat{R} < 1.01$, ESS $> 3800$, PPP $\\in [0.16, 0.25]$). The prior sensitivity confirms that $J=16$ provides insufficient data to override the prior, which reinforces the exploratory status of $\\gamma$-based conclusions at current ensemble sizes.\n\nFor the Social Sciences domain (corrected $J=16$ pool, 2000 items), the directional signal is robust to prior choice:\n\n\\begin{table}[h]\n\\centering\n\\caption{Social Sciences $\\gamma$ prior sensitivity (corrected $J$=16 pool).}\n\\label{tab:socsci_prior}\n\\footnotesize\n\\begin{tabular}{lcc}\n\\toprule\nPrior & $\\hat{\\gamma}$ & $P(\\gamma\\!<\\!0)$ \\\\\n\\midrule\n$\\mathcal{N}(0, 0.5)$ & $-$0.541 & 99.35\\% \\\\\n$\\mathcal{N}(0, 1)$ & $-$0.627 & 99.68\\% \\\\\n$\\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nIn contrast to the pooled analysis where $\\hat{\\gamma}$ shifts 2.6$\\times$ across priors, Social Sciences $\\hat{\\gamma}$ varies only 1.2$\\times$ ($-$0.54 to $-$0.65), with $P(\\gamma<0) \\geq 99.35\\%$ in all cases. The directional signal is robust to prior choice, though the tight prior falls marginally below the Bonferroni threshold (99.375\\% for eight domains).\n\n\\section{IRT Ability Separation by Scale}\n\\label{sec:theta_separation}\n\nTable~\\ref{tab:theta_separation} reports the mean posterior $\\theta$ estimates for 1.5B and 3B model groups across all MMLU domains and the pooled analysis. The ability gap $\\Delta\\theta = \\bar{\\theta}_{3\\text{B}} - \\bar{\\theta}_{1.5\\text{B}}$ is positive and significant (95\\% CI excludes zero) for all nine comparisons, which confirms that the IRT model recovers the expected scale-ability ordering.\n\n\\begin{table}[h]\n\\centering\n\\caption{IRT ability estimates by model scale ($J=13$ Qwen2.5). $\\Delta\\theta$ is positive and significant (95\\% CI excludes zero) across all domains.}\n\\label{tab:theta_separation}\n\\footnotesize\n\\begin{tabular}{lccc}\n\\toprule\nDomain & $\\bar{\\theta}_{1.5\\text{B}}$ & $\\bar{\\theta}_{3\\text{B}}$ & $\\Delta\\theta$ [95\\% CI] \\\\\n\\midrule\nMath & $-$0.532 & 0.119 & 0.651 [0.570, 0.731] \\\\\nScience & 0.321 & 0.780 & 0.459 [0.370, 0.546] \\\\\nCS/Eng & 0.372 & 0.542 & 0.169 [0.030, 0.304] \\\\\nMedical & 0.521 & 1.053 & 0.531 [0.452, 0.609] \\\\\nHumanities & 0.228 & 0.496 & 0.268 [0.202, 0.337] \\\\\nSocial Sci & 0.940 & 1.540 & 0.599 [0.523, 0.675] \\\\\nBusiness/Law & 0.083 & 0.417 & 0.334 [0.261, 0.410] \\\\\nOther & 0.817 & 1.565 & 0.748 [0.647, 0.846] \\\\\n\\midrule\nPooled & 0.311 & 0.811 & 0.500 [0.431, 0.568] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{DiD Across Dosage Levels}\n\\label{sec:did_dosage}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_did_dose_response.pdf}\n\\caption{Difference-in-differences (treated vs.\\ untreated items) across contamination dosage levels. DiD remains non-significant at all dosages for all model families, confirming that the global capability modulation mechanism (\\S\\ref{sec:memorization_test}) is consistent across the full dosage range.}\n\\label{fig:did_dose_response}\n\\end{figure}\n\n\\section{Post-hoc Power Analysis (MDES)}\n\\label{sec:mdes}\n\nTable~\\ref{tab:mdes_mmlu} and Table~\\ref{tab:mdes_arc} report the minimum detectable effect size (MDES) for the treated vs.\\ untreated DiD comparison at d025 (80\\% power, $\\alpha=0.05$, two-sided). MDES is computed as the effect size detectable given each model's observed variance, the treated/untreated split sizes, and a two-sample $t$-test power calculation. At d100, all benchmark items are treated ($n_{\\text{untreated}}=0$), precluding DiD analysis; d025 is reported as the primary dosage level.\n\n\\begin{table}[h]\n\\centering\n\\caption{Post-hoc MDES for MMLU DiD ($n_{\\text{treated}}=3{,}540$, $n_{\\text{untreated}}=10{,}502$).}\n\\label{tab:mdes_mmlu}\n\\footnotesize\n\\begin{tabular}{lcc}\n\\toprule\nModel & DiD (pp) & MDES (pp) \\\\\n\\midrule\nPhi-4 14.7B & $-$0.27 & 1.25 \\\\\nOLMo-2 7B & $-$1.07 & 1.59 \\\\\nGemma-2 9B & $+$0.55 & 1.74 \\\\\nQwen2.5-7B & $-$0.84 & 2.02 \\\\\nQwen2.5-14B & $+$0.69 & 2.05 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\caption{Post-hoc MDES for ARC-Challenge DiD ($n_{\\text{treated}}=257$, $n_{\\text{untreated}}=915$).}\n\\label{tab:mdes_arc}\n\\footnotesize\n\\begin{tabular}{lcc}\n\\toprule\nModel & DiD (pp) & MDES (pp) \\\\\n\\midrule\nPhi-4 14.7B & $-$0.83 & 2.28 \\\\\nQwen2.5-14B & $-$0.26 & 3.47 \\\\\nOLMo-2 7B & $-$1.13 & 4.19 \\\\\nGemma-2 9B & $-$0.25 & 4.66 \\\\\nQwen2.5-7B & $+$2.43 & 5.57 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOn MMLU, all observed DiD values are well below their respective MDES, confirming that the null results are consistent with absence of item-specific effects $>$2pp. On ARC, the smaller treated sample ($n=257$) yields substantially higher MDES; in particular, Qwen-7B's MDES of 5.57pp means that even moderate item-specific effects cannot be excluded for this model on ARC. ARC DiD results should therefore be interpreted as inconclusive rather than as evidence against memorization.\n\n\\section{Dose-Response Details}\n\\label{sec:dose_response_details}\n\nThe dose-response patterns reported in \\S\\ref{sec:taxonomy} are measured at the 7B--14.7B scale. Within the Qwen2.5 family at $\\leq$3B, effects are considerably smaller: at 1.5B and 3B, MMLU accuracy increases with contamination dosage by ${\\sim}$0.6--0.7pp, with diminishing returns above d025. At 0.5B, however, aggregate MMLU accuracy \\textit{decreases} with dosage (0.41 at d000 $\\to$ 0.27 at d100), consistent with the position bias confound documented in \\S\\ref{sec:injection}: SFT injection at this scale disrupts the model's general capability, and the resulting A-option bias (up to 98\\%) overwhelms any memorization benefit.\n\n\\section{Sensitivity of Profile Classification}\n\\label{sec:classification_sensitivity}\n\nWe assess the robustness of Algorithm~\\ref{alg:profile-classification} to threshold selection via a grid sweep over 134 $(\\tau, \\sigma)$ combinations. Table~\\ref{tab:sensitivity} reports family-level stability across both a reasonable parameter range ($\\tau \\in [0.5, 2.0]$~pp $\\times$ $\\sigma \\in [3.0, 7.0]$~pp; 30 combinations) and the full 134-combination sweep, along with the nearest parameter value at which the classification transitions.\n\n\\begin{table}[h]\n\\centering\n\\caption{Profile classification stability across threshold parameter ranges. All families achieve 100\\% stability within the reasonable range; transitions occur only at extreme parameter values ($\\geq$3$\\times$ default).}\n\\label{tab:sensitivity}\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\nFamily & Pattern & Reasonable & Full & Nearest transition \\\\\n\\midrule\nQwen2.5-14B & Collapse & 100\\% & 100\\% & $\\tau = 9.4$ \\\\\nGemma-2 9B & Benefit & 100\\% & 89\\% & $\\tau = 3.8$ \\\\\nPhi-4 14.7B & Immune & 100\\% & 82\\% & $\\tau < 0.35$ \\\\\nOLMo-2 7B & Benefit & 100\\% & 82\\% & $\\tau = 3.25$ \\\\\nQwen2.5-7B & V-recovery & 100\\% & 72\\% & $\\tau = 3.0$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nWithin the reasonable parameter range, all five families achieve 100\\% classification stability (150/150 family--parameter combinations). Transitions occur only at extreme $\\tau$ values well beyond the default ($\\tau\\!=\\!2$): Qwen-14B requires $\\tau\\!=\\!9.4$ (4.7$\\times$ default) to reclassify, reflecting the large separation between its $\\Delta\\text{acc}$ ($-$9.4pp) and any plausible noise threshold. Qwen-7B is the least robust at $\\tau\\!=\\!3.0$ (1.5$\\times$ default), but this is still above any defensible noise threshold for MMLU. The high intrinsic effect-size separation---Phi-4 fluctuates $<$0.4pp while Qwen-14B declines by 9.4pp---means that classification stability is driven by the data rather than by parameter choice.\n\n\\section{Cross-Family Domain Decomposition}\n\\label{sec:domain_decomposition}\n\nWe decompose MMLU accuracy changes into four constituent domains (STEM, Humanities, Social Sciences, Other) across all model families at each contamination dosage.\n\nTwo patterns emerge. First, the direction of accuracy change is governed by the dose-response pattern, not by domain. At d100, Collapse (Qwen-14B) produces negative $\\Delta\\text{acc}$ in all four domains (STEM $-6.8$pp, Humanities $-10.1$pp, Social Sciences $-11.2$pp, Other $-9.4$pp), while Benefit (Gemma-2) produces positive $\\Delta\\text{acc}$ throughout ($+2.7$, $+3.9$, $+5.0$, $+3.4$pp). Immune (Phi-4) remains within $\\pm 1.0$pp across all domains. No pattern produces a crossover exceeding the noise band ($|\\Delta| > 1$pp); the single exception is V-recovery Humanities ($+0.28$pp, well within sampling noise). This consistency holds at intermediate dosages as well.\n\nSecond, domains differ in sensitivity. STEM is the most resilient (mean $|\\Delta\\text{acc}| = 2.8$pp across all families at d100). Social Sciences is the most sensitive at $5.1$pp---$1.8\\times$ the STEM magnitude. The ordering is stable across patterns: in Collapse, STEM shows the smallest decline; in Benefit, STEM shows the smallest gain.\n\nThese results reinforce the global capability modulation interpretation (\\S\\ref{sec:memorization_test}): contamination direction is determined by the model's dose-response pattern rather than domain-specific memorization. The differential domain sensitivity more likely reflects variation in item difficulty distributions than differential memorization rates.\n\n\\section{Baseline Ability vs.\\ Contamination Effect}\n\\label{sec:baseline_vs_effect}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_baseline_vs_effect.pdf}\n\\caption{Baseline MMLU accuracy (d000) vs.\\ maximum accuracy change ($\\Delta$acc) under contamination. A threshold between 61.9\\% (Gemma-2) and 66.1\\% (Qwen-7B) separates models that benefit from contamination (below) from those that are harmed or immune (above). Estimated from models spanning four independent families.}\n\\label{fig:baseline_vs_effect}\n\\end{figure}\n\n\\section{Per-Domain $\\gamma$ Estimates}\n\\label{sec:domain_gamma_table}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_domain_gamma.pdf}\n\\caption{Per-domain $\\gamma_d$ estimates with 95\\% CIs ($J$=13 Qwen2.5). STEM domains show positive $\\gamma_d$; Social Sciences is negative and survives Bonferroni correction at $J$=16.}\n\\label{fig:domain_gamma}\n\\end{figure}\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-domain $\\gamma$ estimates (2PL+$\\gamma$, Qwen2.5) at $J$=13 and $J$=16. All $J$=16 fits converge ($\\hat{R} < 1.01$). Social Sciences $P(\\gamma\\!<\\!0)$ strengthens from 99.1\\% to 99.7\\% at $J$=16, crossing the Bonferroni-corrected threshold of 99.375\\% for eight tests. Results remain exploratory at these ensemble sizes \\citep{gelman2012why}. ARC-Challenge is excluded (PPP $<$ 0.05 at all $J$).}\n\\label{tab:domain_gamma}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccccc}\n\\toprule\n & \\multicolumn{2}{c}{$J$=13} & \\multicolumn{4}{c}{$J$=16} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-7}\nDomain & $\\gamma$ & $P(\\gamma\\!<\\!0)$ & $\\gamma$ & $P(\\gamma\\!<\\!0)$ & PPP & $\\hat{R}$ \\\\\n\\midrule\nMMLU: Math & +0.50 & 8.1\\% & +0.60 & 3.8\\% & 0.305 & 1.007 \\\\\nMMLU: Science & +0.50 & 7.8\\% & +0.57 & 4.3\\% & 0.197 & 1.007 \\\\\nMMLU: CS/Eng & +0.50 & 14.8\\% & +0.32 & 24.0\\% & 0.503 & 1.006 \\\\\nMMLU: Medical & +0.24 & 24.0\\% & +0.05 & 43.6\\% & 0.268 & 1.008 \\\\\nMMLU: Other & +0.13 & 35.7\\% & +0.32 & 20.4\\% & 0.072$^\\dagger$ & 1.008 \\\\\nMMLU: Business/Law & +0.04 & 44.1\\% & +0.08 & 37.8\\% & 0.395 & 1.007 \\\\\nMMLU: Humanities & $-$0.31 & 85.4\\% & $-$0.14 & 69.7\\% & 0.416 & 1.007 \\\\\nMMLU: Social Sci & $-$0.57 & \\textbf{99.1\\%} & $-$0.63 & \\textbf{99.7\\%} & 0.722 & 1.006 \\\\\n\\bottomrule\n\\end{tabular}}\n\n\\vspace{2pt}\n{\\scriptsize $^\\dagger$PPP below acceptable threshold (0.1); $\\gamma$ estimate for this domain should be interpreted with caution.}\n\\end{table}\n\n\\section{DGP Robustness Analysis}\n\\label{sec:threshold_dgp}\n\nWe evaluate 2PL+$\\gamma$ robustness under data-generating process (DGP) misspecification via 400 simulation runs (2 DGPs $\\times$ 4 ensemble sizes $\\times$ 5 true $\\gamma$ values $\\times$ 10 seeds).\n\n\\paragraph{Design.} The \\emph{Linear DGP} (control) generates responses from the correctly specified additive model (Eq.~\\ref{eq:2pl_gamma}). The \\emph{Threshold DGP} (misspecified) applies a step-function contamination effect: items with exposure above a threshold receive the full effect; items below receive zero. Ensemble sizes sweep $J \\in \\{16, 50, 100, 500\\}$; true $\\gamma \\in \\{0.5, 1.0, 1.5, 2.0, 3.0\\}$.\n\n\\paragraph{Point estimates.} Under the Linear DGP, $\\hat{\\gamma}/\\gamma_{\\text{true}} = 0.84$--$1.07$ across all conditions (unbiased within sampling noise). Under the Threshold DGP, $\\hat{\\gamma}/\\gamma_{\\text{true}} = 0.94$--$1.24$ (mild overestimation, not attenuation). PPP remains in the acceptable range (0.50--0.56) under both DGPs, confirming that posterior predictive checks cannot detect this form of misspecification.\n\n\\paragraph{CI coverage.} Under the Linear DGP, 95\\% CI coverage is nominal ($\\geq$0.93) at all $J$. Under the Threshold DGP, coverage degrades with ensemble size (Table~\\ref{tab:dgp_coverage}). The intervals become overconfident as $J$ increases because the model converges to a biased point estimate.\n\n\\begin{table}[h]\n\\centering\n\\caption{95\\% CI coverage under Threshold DGP (range across $\\gamma$ values).}\n\\label{tab:dgp_coverage}\n\\footnotesize\n\\begin{tabular}{lc}\n\\toprule\n$J$ & 95\\% CI coverage \\\\\n\\midrule\n50 & 1.00 \\\\\n100 & 0.90--1.00 \\\\\n200 & 0.80--1.00 \\\\\n500 & 0.70--1.00 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Implications.} The reasoning chain is: (i)~Threshold DGP + linear model yields $\\hat{\\gamma}/\\gamma_{\\text{true}} \\geq 0.94$ (overestimation, not attenuation); (ii)~therefore, if a true threshold effect exists, the linear model will not fail to detect it; (iii)~an empirical $\\gamma \\approx 0$ is a genuine null, not a misspecification artifact. Coverage degradation affects the \\emph{precision} of effect size estimates (how narrow the CI is), not the \\emph{detection} of whether an effect exists. At the ensemble sizes in our empirical analyses ($J\\!=\\!13$--$16$), coverage remains near-nominal even under misspecification. Real RRF exposure is right-skewed (mean$=$0.041); the simulation uses uniform exposure, so quantitative magnitudes may differ, but the qualitative pattern (overestimation direction, coverage degradation at large $J$) is robust.\n\n\\section{ARC IRT Results}\n\\label{sec:arc_irt}\n\nARC-Challenge IRT results are reported separately due to marginal model fit (PPP$=$0.003 at $J=16$). The smaller item pool (1,172 vs.\\ 14,042 for MMLU) and more homogeneous difficulty distribution contribute to structural misfit: the 2PL+$\\gamma$ model cannot adequately capture the item response patterns. Under this caveat, the ARC baseline comparison ($J=16$, 300 RRF items) yields: B0-Raw MAE$=$0.007, B3-Vanilla2PL MAE$=$0.015, B4-LinearRegression MAE$=$0.012 ($\\tau = 0.731$, best rank correlation), B6-DCR MAE$=$0.314 (systematic overcorrection), ContamCal MAE$=$0.020. The pattern mirrors MMLU: raw accuracy dominates on MAE because the aggregate contamination effect (${\\sim}$0.7pp) is smaller than correction noise. Domain-level $\\gamma$ estimation on ARC is unreliable at all tested configurations ($J=8$, 13, 16; PPP $< 0.05$ in all cases).\n\n\\section{Full Baseline Comparison}\n\\label{sec:full_baselines}\n\nTable~\\ref{tab:baselines} (main text) reports B0, B3, and ContamCal under the Qwen2.5 pooled configuration ($J=16$ for MMLU/ARC, $J=24$ for GSM8K which retains 0.5B). Table~\\ref{tab:full_baselines_arc} presents the complete seven-baseline comparison on ARC under a pooled 0.5B+1.5B configuration ($J=8$, S1-only exposure). This configuration differs from the main analysis ($J=16$, RRF exposure): the smaller ensemble and single-signal exposure limit comparability with MMLU results; these results are included for completeness. Table~\\ref{tab:full_baselines_gsm8k} presents GSM8K baselines at 0.5B scale.\n\nB6-DCR \\citep{xu2025dcr} produces the highest MAE on both benchmarks, consistent with its fuzzy inference approach, which overcorrects scores without a measurement-theoretic anchor. B4-LinearRegression performs competitively on ARC (MAE$=$0.056) but lacks the uncertainty quantification and domain-level diagnosis that IRT provides. B1-Remove\\&Rescore and B5-Emperor do not improve over raw scores, which confirms that item removal and mitigation strategies are insufficient for calibration.\n\n\\begin{table}[h]\n\\centering\n\\caption{Full baseline comparison on ARC-Challenge (pooled 0.5B+1.5B, $J=8$, S1-only exposure). MAE$\\downarrow$.}\n\\label{tab:full_baselines_arc}\n\\footnotesize\n\\begin{tabular}{lc}\n\\toprule\nMethod & ARC MAE \\\\\n\\midrule\nB0-Raw & 0.059 \\\\\nB1-Remove\\&Rescore & 0.059 \\\\\nB2-Single2PL+$\\gamma$ & 0.064 \\\\\nB3-Vanilla4PL & 0.071 \\\\\nB4-LinearRegression & 0.056 \\\\\nB5-Emperor & 0.059 \\\\\nB6-DCR & --- \\\\\n\\midrule\nContamCal (4PL+$\\gamma$) & \\textbf{0.035} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\caption{Baseline comparison on GSM8K (0.5B scale, delta exposure). MAE$\\downarrow$.}\n\\label{tab:full_baselines_gsm8k}\n\\footnotesize\n\\begin{tabular}{lc}\n\\toprule\nMethod & GSM8K MAE \\\\\n\\midrule\nB0-Raw & 0.003 \\\\\nB2-Single2PL+$\\gamma$ & 0.320 \\\\\nB3-Vanilla4PL & 0.012 \\\\\nB4-LinearRegression & \\textbf{0.003} \\\\\nB6-DCR & --- \\\\\n\\midrule\nContamCal (4PL+$\\gamma$) & 0.020 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Parametric Dose-Response Model Comparison}\n\\label{sec:parametric_dr}\n\nWe fit four parametric dose-response models---Constant (intercept-only), Linear, Quadratic, and four-parameter Hill \\citep{hill1910aggregation,ritz2015dose}---to pooled multi-seed MMLU accuracy trajectories for each family. Table~\\ref{tab:aicc_dr} reports AICc and Akaike weights.\n\n\\begin{table}[h]\n\\centering\n\\caption{AICc model selection for dose-response trajectories (pooled multi-seed MMLU). Bold indicates best-fitting model per family; $w$ is the Akaike weight of the best model.}\n\\label{tab:aicc_dr}\n\\footnotesize\n\\begin{tabular}{lccccc}\n\\toprule\nFamily & Constant & Linear & Quadratic & Hill & Best ($w$) \\\\\n\\midrule\nPhi-4 14.7B & $-$71.42 & $-$72.08 & $-$70.06 & $\\mathbf{-73.14}$ & Hill (0.58) \\\\\nQwen2.5-14B & 49.54 & 23.40 & 21.22 & $\\mathbf{18.28}$ & Hill (0.55) \\\\\nQwen2.5-7B & $-$12.38 & $-$20.53 & $-$14.52 & $\\mathbf{-24.97}$ & Hill (0.77) \\\\\nGemma-2 9B & $\\mathbf{17.35}$ & 18.89 & 20.01 & 18.96 & Constant (0.39) \\\\\nOLMo-2 7B & $\\mathbf{25.82}$ & 26.66 & 27.54 & 26.47 & Constant (0.62) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nParametric model selection with pooled multi-seed data recovers only the most extreme pattern (Collapse, Qwen-14B; Hill $E_{\\max} = -43$pp). Two families classified as Benefit by Algorithm~\\ref{alg:profile-classification} (Gemma-2, OLMo-2) are indistinguishable from Constant under AICc---consistent with their cross-seed CIs crossing zero (Table~\\ref{tab:cross_seed}). Qwen-7B's V-recovery is structurally inaccessible to monotonic Hill/sigmoid models; Quadratic captures the V-shape but is penalized by AICc ($\\Delta$AICc$=$6.4). Phi-4's Immune classification is reclassified as weak Benefit (Hill $E_{\\max} = +2.43$pp, CI [$-$2.01, $+$6.88] crossing zero). These discrepancies reflect insufficient statistical power at $n\\!=\\!3$ seeds rather than contradictions: Algorithm~\\ref{alg:profile-classification} resolves per-seed patterns below the detection threshold of pooled parametric methods, motivating its use for taxonomy construction.\n\n\\section{Exposure Score Item-Level Classification}\n\\label{sec:sij_classification}\n\nUnder controlled injection where ground-truth contamination labels are available, we evaluate item-level classification performance of each detection signal and the RRF fusion (\\S\\ref{sec:stage1}). S1 (embedding similarity) achieves near-perfect discrimination (ROC-AUC 0.93--0.99 across benchmarks and dosage levels), confirming that cosine similarity to the training corpus reliably identifies injected items. RRF fusion achieves ROC-AUC 0.73--0.93, reduced relative to S1 because S2 (Min-K\\%++, AUC $\\approx$ 0.48--0.50) and S4 (Self-Critique, AUC $\\approx$ 0.47--0.51) contribute near-random item-level signal. However, RRF is designed for the realistic setting where ground truth is unavailable: S1 requires an explicit training corpus reference, which practitioners typically lack, while RRF's multi-signal approach provides robustness across detection scenarios where no single signal dominates (\\S\\ref{sec:rrf_ablation}).\n",
      "numLines": 498,
      "startLine": 1,
      "totalLines": 498
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
Now I have both files. Let me analyze what I need to do:

**Task 1: LoRA parameter percentage**
In `limitations.tex` (line 4), I can see: "Unified LoRA rank ($r\!=\!16$) yields a parameter fraction inversely proportional to model size; Phi-4's immunity may partly reflect insufficient adaptation capacity, though Qwen-14B's collapse at the same scale argues against a purely capacity-based explanation."

I need to add "specifically, 0.45\\% for Phi-4 (14.7B) and 0.59\\% for Gemma-2 (9B)." after "model size".
 
**Task 2: Table 10 (prior sensitivity)**
Looking at the appendix, I found the Prior Sensitivity Analysis section with the Social Sciences γ prior sensitivity table. The server confirmed that only Social Sciences was rerun with J=16, but the task mentions Table 10 should have other domains too. Let me check if there's another table I'm missing or if this one needs to be expanded.

The current table shows the baseline case with γ̂=-0.627 and P(γ<0)=99.68%, which matches the "new values" mentioned in the task description. This suggests the table may have already been updated from the old values (γ̂=-0.497, P(γ<0)=98.48%), so I need to verify whether this is the complete Table 10 or if additional domains should be included. I need to check whether Table 10 actually exists as a multi-domain prior sensitivity table or if the user is referring to the Social Sciences-specific table that's already been updated. Let me trace through the document structure to see what tables are present and how they're numbered, since the current table already contains the corrected values the user mentioned. The table caption explicitly mentions "corrected J=16 pool," which confirms these are the updated values. Since only Social Sciences was rerun and the table only displays Social Sciences data, I need to determine whether a footnote is required to clarify that other domains weren't included in this sensitivity analysis. the table's caption, so I should verify whether the footnote belongs there or if it makes more sense to clarify the correction at the section level or on the domain gamma table instead.

Looking at the per-domain gamma table, the Social Sciences row already shows the updated values—gamma of -0.63 with 99.7% for the larger model. It appears these corrections may have already been applied, so I need to focus on what's actually still missing: adding the LoRA parameter percentages and ensuring the footnote is properly placed.

For the footnote about the corrected prior sensitivity pool, since the Social Sciences prior table caption already mentions "(corrected J=16 pool)," I should consider whether the note about other domains retaining the original pool belongs there or on the domain gamma table instead. The user's reference to "Table 10" points to the Social Sciences prior table around line 208, which is where this clarification would be most relevant.

Now I need to tackle two things: add the LoRA percentages to the limitations section, and insert a footnote below the prior sensitivity table explaining that only Social Sciences was re-run with the corrected J=16 pool while other domains kept their original settings.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "c96275a8-943d-4ab9-a157-8564d91e5ae3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HDXKLjZcH5puQUVMcNHs8R",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15383,
      "cache_read_input_tokens": 28677,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15383
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

Server confirms only `social_sciences/` exists in `gamma_prior_sensitivity_j16/`. The table values in appendix.tex are already the new values (-0.627, 99.68% for baseline). I'll add the LoRA percentages to limitations and the footnote to the prior sensitivity table.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "2f23d88d-01e1-4ad1-8931-d0e32b9e26cf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HDXKLjZcH5puQUVMcNHs8R",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15383,
      "cache_read_input_tokens": 28677,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15383
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

<details open><summary>🔧 Tool call — Edit · `toolu_01DBhUWHDf9Yvb4MdVq4icK1`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/limitations.tex",
  "old_string": "Unified LoRA rank ($r\\!=\\!16$) yields a parameter fraction inversely proportional to model size;",
  "new_string": "Unified LoRA rank ($r\\!=\\!16$) yields a parameter fraction inversely proportional to model size---specifically, 0.45\\% for Phi-4 (14.7B) and 0.59\\% for Gemma-2 (9B);"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "9c41100d-6ffa-489e-a454-b91398b56bd0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HDXKLjZcH5puQUVMcNHs8R",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15383,
      "cache_read_input_tokens": 28677,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15383
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

_source line 34 · 2026-05-21T19:57:20.953Z_

<details><summary>↩ Tool result · `toolu_01DBhUWHDf9Yvb4MdVq4icK1`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/limitations.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "93e34794-4153-4732-be21-ca7f14f3830a",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/limitations.tex",
    "oldString": "Unified LoRA rank ($r\\!=\\!16$) yields a parameter fraction inversely proportional to model size;",
    "newString": "Unified LoRA rank ($r\\!=\\!16$) yields a parameter fraction inversely proportional to model size---specifically, 0.45\\% for Phi-4 (14.7B) and 0.59\\% for Gemma-2 (9B);",
    "originalFile": "\\section*{Limitations}\n\\label{sec:limitations}\n\nAll experiments use models at or below 14.7B parameters; 70B+ models may exhibit qualitatively different contamination dynamics where SFT injection is absorbed without measurable signal divergence. With $n\\!=\\!3$ seeds per family, effect \\emph{direction} is reproducible but magnitude is seed-sensitive (OLMo-2's cross-seed CI crosses zero, rendering its Benefit classification borderline), and borderline classifications should be interpreted with caution. Finally, our LoRA-based SFT injection in AUGMENT mode differs from pretraining-stage leakage via web crawl ingestion, and our dosage levels assume uniform injection of all benchmark items; real-world contamination may follow skewed exposure distributions, potentially producing different dose-response profiles. Unified LoRA rank ($r\\!=\\!16$) yields a parameter fraction inversely proportional to model size; Phi-4's immunity may partly reflect insufficient adaptation capacity, though Qwen-14B's collapse at the same scale argues against a purely capacity-based explanation. Out-of-sample validation covers only the Immune pattern; independent-family replication of Collapse, V-recovery, and Benefit remains open. All single-family patterns are, however, replicated across three random seeds. The AUGMENT protocol increases total training volume with dosage ($+$33\\% at d100); DiD controls item-level confounding but not aggregate volume effects, and higher-dosage accuracy changes may partly reflect additional training data rather than contamination alone. IRT is fitted on the 300 highest-exposure-variance items (2.1\\% of MMLU); contamination effects on the remaining low-variance items may differ. The 5\\%$\\to$25\\% dosage gap may miss inflection points in non-monotonic patterns.\n",
    "structuredPatch": [
      {
        "oldStart": 1,
        "oldLines": 4,
        "newStart": 1,
        "newLines": 4,
        "lines": [
          " \\section*{Limitations}",
          " \\label{sec:limitations}",
          " ",
          "-All experiments use models at or below 14.7B parameters; 70B+ models may exhibit qualitatively different contamination dynamics where SFT injection is absorbed without measurable signal divergence. With $n\\!=\\!3$ seeds per family, effect \\emph{direction} is reproducible but magnitude is seed-sensitive (OLMo-2's cross-seed CI crosses zero, rendering its Benefit classification borderline), and borderline classifications should be interpreted with caution. Finally, our LoRA-based SFT injection in AUGMENT mode differs from pretraining-stage leakage via web crawl ingestion, and our dosage levels assume uniform injection of all benchmark items; real-world contamination may follow skewed exposure distributions, potentially producing different dose-response profiles. Unified LoRA rank ($r\\!=\\!16$) yields a parameter fraction inversely proportional to model size; Phi-4's immunity may partly reflect insufficient adaptation capacity, though Qwen-14B's collapse at the same scale argues against a purely capacity-based explanation. Out-of-sample validation covers only the Immune pattern; independent-family replication of Collapse, V-recovery, and Benefit remains open. All single-family patterns are, however, replicated across three random seeds. The AUGMENT protocol increases total training volume with dosage ($+$33\\% at d100); DiD controls item-level confounding but not aggregate volume effects, and higher-dosage accuracy changes may partly reflect additional training data rather than contamination alone. IRT is fitted on the 300 highest-exposure-variance items (2.1\\% of MMLU); contamination effects on the remaining low-variance items may differ. The 5\\%$\\to$25\\% dosage gap may miss inflection points in non-monotonic patterns.",
          "+All experiments use models at or below 14.7B parameters; 70B+ models may exhibit qualitatively different contamination dynamics where SFT injection is absorbed without measurable signal divergence. With $n\\!=\\!3$ seeds per family, effect \\emph{direction} is reproducible but magnitude is seed-sensitive (OLMo-2's cross-seed CI crosses zero, rendering its Benefit classification borderline), and borderline classifications should be interpreted with caution. Finally, our LoRA-based SFT injection in AUGMENT mode differs from pretraining-stage leakage via web crawl ingestion, and our dosage levels assume uniform injection of all benchmark items; real-world contamination may follow skewed exposure distributions, potentially producing different dose-response profiles. Unified LoRA rank ($r\\!=\\!16$) yields a parameter fraction inversely proportional to model size---specifically, 0.45\\% for Phi-4 (14.7B) and 0.59\\% for Gemma-2 (9B); Phi-4's immunity may partly reflect insufficient adaptation capacity, though Qwen-14B's collapse at the same scale argues against a purely capacity-based explanation. Out-of-sample validation covers only the Immune pattern; independent-family replication of Collapse, V-recovery, and Benefit remains open. All single-family patterns are, however, replicated across three random seeds. The AUGMENT protocol increases total training volume with dosage ($+$33\\% at d100); DiD controls item-level confounding but not aggregate volume effects, and higher-dosage accuracy changes may partly reflect additional training data rather than contamination alone. IRT is fitted on the 300 highest-exposure-variance items (2.1\\% of MMLU); contamination effects on the remaining low-variance items may differ. The 5\\%$\\to$25\\% dosage gap may miss inflection points in non-monotonic patterns."
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

_source line 35_

<details open><summary>🔧 Tool call — Edit · `toolu_01BMR579kyNXncvHQ6kSP4Cj`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex",
  "old_string": "\\begin{tabular}{lcc}\n\\toprule\nPrior & $\\hat{\\gamma}$ & $P(\\gamma\\!<\\!0)$ \\\\\n\\midrule\n$\\mathcal{N}(0, 0.5)$ & $-$0.541 & 99.35\\% \\\\\n$\\mathcal{N}(0, 1)$ & $-$0.627 & 99.68\\% \\\\\n$\\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}",
  "new_string": "\\begin{tabular}{lcc}\n\\toprule\nPrior & $\\hat{\\gamma}$ & $P(\\gamma\\!<\\!0)$ \\\\\n\\midrule\n$\\mathcal{N}(0, 0.5)$ & $-$0.541 & 99.35\\% \\\\\n$\\mathcal{N}(0, 1)$ & $-$0.627 & 99.68\\% \\\\\n$\\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\\% \\\\\n\\bottomrule\n\\multicolumn{3}{l}{\\scriptsize Social Sciences row updated with corrected $J\\!=\\!16$ model pool;} \\\\\n\\multicolumn{3}{l}{\\scriptsize other domains retain the original prior sensitivity pool.}\n\\end{tabular}\n\\end{table}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "f06b510e-fdf4-416b-879e-f09c1acb29bf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HDXKLjZcH5puQUVMcNHs8R",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15383,
      "cache_read_input_tokens": 28677,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15383
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

_source line 36 · 2026-05-21T19:57:25.355Z_

<details><summary>↩ Tool result · reported error · `toolu_01BMR579kyNXncvHQ6kSP4Cj`</summary>

```text
&lt;tool_use_error>File has been modified since read, either by the user or by a linter. Read it again before attempting to write it.&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "a7f37c81-c48d-48a8-aca8-56374bae246a",
  "tool_use_result": "Error: File has been modified since read, either by the user or by a linter. Read it again before attempting to write it."
}
```

</details>

---

### Assistant

_source line 37_

<details><summary>Logged reasoning block</summary>

```text
The appendix file was modified since I read it. Let me re-read the relevant section.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "e8f09d06-1a0e-4af1-a0fe-ded065bb74d4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VjXCJ5RjNYDLdpgMKjEosy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3320,
      "cache_read_input_tokens": 44060,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3320
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

_source line 38_

<details open><summary>🔧 Tool call — Read · `toolu_01Fqqvh9vhki7FejHdT1GfkN`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex",
  "offset": 196,
  "limit": 20
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "9d1a9721-fe53-4a8c-8a0c-df9182cc347a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VjXCJ5RjNYDLdpgMKjEosy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3320,
      "cache_read_input_tokens": 44060,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3320
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

_source line 39 · 2026-05-21T19:57:29.526Z_

<details><summary>↩ Tool result · `toolu_01Fqqvh9vhki7FejHdT1GfkN`</summary>

```text
196	For the Social Sciences domain (corrected $J=16$ pool, 2000 items), the directional signal is robust to prior choice:
197	
198	\begin{table}[h]
199	\centering
200	\caption{Social Sciences $\gamma$ prior sensitivity (corrected $J$=16 pool).}
201	\label{tab:socsci_prior}
202	\footnotesize
203	\begin{tabular}{lcc}
204	\toprule
205	Prior & $\hat{\gamma}$ & $P(\gamma\!<\!0)$ \\
206	\midrule
207	$\mathcal{N}(0, 0.5)$ & $-$0.541 & 99.35\% \\
208	$\mathcal{N}(0, 1)$ & $-$0.627 & 99.68\% \\
209	$\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\% \\
210	\bottomrule
211	\end{tabular}
212	\end{table}
213	
214	In contrast to the pooled analysis where $\hat{\gamma}$ shifts 2.6$\times$ across priors, Social Sciences $\hat{\gamma}$ varies only 1.2$\times$ ($-$0.54 to $-$0.65), with $P(\gamma<0) \geq 99.35\%$ in all cases. The directional signal is robust to prior choice, though the tight prior falls marginally below the Bonferroni threshold (99.375\% for eight domains).
215	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "ef8dca77-36a2-429b-a4b5-869d74832a03",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex",
      "content": "For the Social Sciences domain (corrected $J=16$ pool, 2000 items), the directional signal is robust to prior choice:\n\n\\begin{table}[h]\n\\centering\n\\caption{Social Sciences $\\gamma$ prior sensitivity (corrected $J$=16 pool).}\n\\label{tab:socsci_prior}\n\\footnotesize\n\\begin{tabular}{lcc}\n\\toprule\nPrior & $\\hat{\\gamma}$ & $P(\\gamma\\!<\\!0)$ \\\\\n\\midrule\n$\\mathcal{N}(0, 0.5)$ & $-$0.541 & 99.35\\% \\\\\n$\\mathcal{N}(0, 1)$ & $-$0.627 & 99.68\\% \\\\\n$\\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nIn contrast to the pooled analysis where $\\hat{\\gamma}$ shifts 2.6$\\times$ across priors, Social Sciences $\\hat{\\gamma}$ varies only 1.2$\\times$ ($-$0.54 to $-$0.65), with $P(\\gamma<0) \\geq 99.35\\%$ in all cases. The directional signal is robust to prior choice, though the tight prior falls marginally below the Bonferroni threshold (99.375\\% for eight domains).\n",
      "numLines": 20,
      "startLine": 196,
      "totalLines": 498
    }
  }
}
```

</details>

---

### Tool call

_source line 40_

<details open><summary>🔧 Tool call — Edit · `toolu_01UPmbQDQtqX4pY5ZCgirSFy`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex",
  "old_string": "$\\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}",
  "new_string": "$\\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\\% \\\\\n\\bottomrule\n\\multicolumn{3}{l}{\\scriptsize Social Sciences row updated with corrected $J\\!=\\!16$ model pool;} \\\\\n\\multicolumn{3}{l}{\\scriptsize other domains retain the original prior sensitivity pool.}\n\\end{tabular}\n\\end{table}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "1bd275dd-a1c4-41a0-acff-20c7b824fbbf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RjbosapB4BosZmZBfvqc6z",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 585,
      "cache_read_input_tokens": 47380,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 585
      },
      "output_tokens": 65,
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

_source line 41 · 2026-05-21T19:57:39.117Z_

<details><summary>↩ Tool result · `toolu_01UPmbQDQtqX4pY5ZCgirSFy`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "22bfc109-830d-4d0f-b0c7-0a7defe20d6e",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/docs/paper/appendix.tex",
    "oldString": "$\\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}",
    "newString": "$\\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\\% \\\\\n\\bottomrule\n\\multicolumn{3}{l}{\\scriptsize Social Sciences row updated with corrected $J\\!=\\!16$ model pool;} \\\\\n\\multicolumn{3}{l}{\\scriptsize other domains retain the original prior sensitivity pool.}\n\\end{tabular}\n\\end{table}",
    "originalFile": "\\appendix\n\n\\section{Cross-Benchmark Transfer Details}\n\\label{sec:cross_benchmark_details}\n\n\\begin{table}[h]\n\\centering\n\\caption{Cross-benchmark transfer: MMLU vs.\\ GSM8K accuracy change at d100. LLaMA-3.1 shows the strongest asymmetric transfer ($+$16.4pp GSM8K despite MMLU immunity). Gemma-2 excluded due to CoT collapse under MC-format SFT.}\n\\label{tab:gsm8k_transfer}\n\\footnotesize\n\\begin{tabular}{lcccl}\n\\toprule\nModel & MMLU $\\Delta$ & GSM8K $\\Delta$ & Range & Transfer \\\\\n\\midrule\nPhi-4 14.7B & $\\pm$0.5pp & $-$0.5pp & --- & Null \\\\\nOLMo-2 7B & $+$3.2pp & $+$2.1pp$^{\\S}$ & --- & Consistent \\\\\nQwen-7B & $-$1.8pp & $+$10.1pp & $\\pm$0.9 & Reversal \\\\\nQwen-14B & $-$9.4pp & $+$13.1pp & $\\pm$7.4 & Reversal$^{\\dagger}$ \\\\\nLLaMA-3.1 8B & $-$0.7pp & $+$16.4pp$^{\\ddagger}$ & --- & Asymmetric \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\scriptsize $^{\\dagger}$d000 baseline seed-sensitive (s42$=$60.8\\% vs.\\ s123$=$76.7\\%); d100 stable ($82\\pm0.5$\\%).} \\\\\n\\multicolumn{5}{l}{\\scriptsize $^{\\S}$Seed$=$42; OLMo-2 GSM8K effect is seed-sensitive (s42: $+$2.1pp vs.\\ s0: $+$9.2pp).} \\\\\n\\multicolumn{5}{l}{\\scriptsize $^{\\ddagger}$Single seed (s0); MMLU Immune but strongest GSM8K transfer across all families.}\n\\end{tabular}\n\\end{table}\n\n\\section{ARC-Challenge Cross-Benchmark Analysis}\n\\label{sec:arc_cross_benchmark}\n\nARC-Challenge (25-shot, 1{,}172 items) patterns under s42 are directionally consistent with MMLU for four of five models: OLMo-2 benefits ($+$3.9pp), Qwen-7B ($-$2.9pp) and Qwen-14B ($-$3.4pp) are harmed, Phi-4 remains immune ($+$0.6pp). Gemma-2 achieves $n\\!=\\!3$ on ARC: s42 exhibits a 16pp oscillation artifact (endpoint $-$1.20pp), s0 shows harm ($-$1.97pp), and s123 shows benefit ($+$2.73pp). The $n\\!=\\!3$ ARC mean is $-$0.15pp (SD$=$2.41pp; BCa 95\\% CI [$-$1.97, $+$1.42]), with cross-seed direction inconsistent ($-$/$-$/$+$). This contrasts with MMLU, where all three seeds show benefit (mean $+$2.38pp, CI [$+$1.49, $+$3.14] excludes zero), making Gemma-2 the clearest example of benchmark-conditional contamination effects. Bootstrap stability is substantially lower than MMLU (OLMo-2: 53.3\\%, Gemma-2: 62.7\\%) due to the smaller item pool (1{,}172 vs.\\ 14{,}042).\n\n\\paragraph{Cross-seed ARC consistency.}\nPhi-4 is the strongest anchor with $n\\!=\\!3$ on both benchmarks: ARC mean $\\Delta = +0.66$pp (SD$=$0.18pp; s0 $+$0.51, s42 $+$0.60, s123 $+$0.86; BCa 95\\% CI [$+$0.51, $+$0.77]), MMLU mean $\\Delta = +0.73$pp---cross-benchmark agreement within 0.07pp. While statistically detectable on ARC (CI excludes zero, unlike MMLU CI [$-$0.17, $+$1.39]), the effect ($+$0.66pp) is too small to meaningfully inflate benchmark scores, consistent with the Immune classification. Qwen-7B achieves $n\\!=\\!3$ on ARC: mean $\\Delta = -2.42$pp (SD$=$0.51pp; s0 $-$1.88, s42 $-$2.90, s123 $-$2.47; BCa 95\\% CI [$-$2.90, $-$2.08]), confirming persistent harm. The d005 V-dip severity is seed-dependent ($-$1.8pp vs.\\ $-$4.7pp). Qwen-14B achieves $n\\!=\\!3$ on both benchmarks: MMLU mean $\\Delta = -15.7$pp (BCa CI [$-$24.99, $-$10.49]; s0 most extreme at $-$25.0pp due to position bias amplification); ARC mean $\\Delta = -5.03$pp (BCa CI [$-$9.38, $-$2.76]). Both CIs exclude zero, confirming Collapse. OLMo-2 achieves $n\\!=\\!3$ on ARC: mean $\\Delta = +3.44$pp (SD$=$0.52pp; s0 $+$3.50, s42 $+$3.92, s123 $+$2.90). Despite being the most seed-sensitive family on MMLU (SD$=$1.9pp), OLMo-2 is remarkably stable on ARC (SD$=$0.52pp)---seed sensitivity is itself benchmark-dependent, likely modulated by item count and difficulty distribution. Using multi-seed MMLU means ($+$1.4pp), direction is consistently positive on both benchmarks, illustrating why cross-benchmark comparisons require multi-seed aggregation (\\S\\ref{sec:cross_seed}). ARC dose-response trajectories (s123): Qwen-14B 90.4$\\to$91.5$\\to$89.8$\\to$88.7$\\to$87.3 (d005 transient spike then monotonic decline, consistent with MMLU s123 shape); Qwen-7B 87.1$\\to$82.4$\\to$85.2$\\to$85.1$\\to$84.7 (d005 sharp drop then partial recovery); OLMo-2 76.9$\\to$77.2$\\to$76.6$\\to$79.2$\\to$79.8 (monotonic rise).\n\nCross-seed direction on ARC is consistent for 4/5 families: Phi-4 and OLMo-2 positive across three seeds each, Qwen-7B and Qwen-14B negative across three seeds each. Gemma-2 is the exception ($-$/$-$/$+$ across seeds; mean $-$0.15pp). This contrasts with MMLU, where only 2/5 families achieve strict sign consistency (\\S\\ref{sec:cross_seed}). ARC yields tighter confidence intervals and higher cross-seed consistency than MMLU, likely because its smaller item pool (1{,}172 vs.\\ 14{,}042) amplifies the contamination signal---suggesting that benchmark size modulates not only effect magnitude but also statistical detectability.\n\nCross-benchmark direction (MMLU vs.\\ ARC) is consistent for 3/5 families (\\S\\ref{sec:gsm8k_transfer}): Qwen-14B (Harm), Phi-4 (Immune), and OLMo-2 (Benefit). Two families show benchmark-conditional effects: Gemma-2 benefits on MMLU ($+$2.38pp, CI excludes zero) but shows no significant ARC effect ($-$0.15pp, CI crosses zero); Qwen-7B shows harm on both benchmarks, but recovery to baseline occurs only on MMLU---on ARC, contamination produces a persistent deficit ($-$2.4pp mean across three seeds). Effect magnitudes remain benchmark-specific: Qwen-14B suffers $-$5.0pp on ARC compared to $-$15.7pp on MMLU (3.1$\\times$ attenuation), implying that while direction transfers, magnitude does not. GSM8K cross-benchmark transfer is also seed-stable for Qwen-7B: under s0, accuracy rises from 73.3\\% to 81.2\\% ($+$7.9pp, monotonic), consistent with the directional reversal observed under s42 ($+$10.1pp; Table~\\ref{tab:gsm8k_transfer}).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_arc_dose_response.pdf}\n\\caption{ARC-Challenge accuracy vs.\\ contamination dosage (25-shot). Patterns are directionally consistent with MMLU (Figure~\\ref{fig:dose_response}) for 4/5 models.}\n\\label{fig:dose_response_arc}\n\\end{figure}\n\n\\section{GSM8K Dose-Response Transfer}\n\\label{sec:gsm8k_dose_response}\n\nTable~\\ref{tab:gsm8k_dose} reports GSM8K accuracy across contamination dosages for all six families (single seed, s0). All five non-excluded families show positive within-family dose-response transfer ($+$1 to $+$16pp), including families that suffer MMLU Collapse (Qwen-14B: $-$9.4pp MMLU, $+$7.4pp GSM8K) or are MMLU-Immune (LLaMA-3.1: $-$0.7pp MMLU, $+$16.4pp GSM8K---the strongest transfer effect). This directional reversal---MMLU-targeted contamination improving an unrelated open-ended math benchmark---strengthens the global capability modulation interpretation. Within-family dose-response patterns (direction and relative magnitude of $\\Delta$) are the primary finding, as all dosage levels for each family use identical evaluation settings.\n\n\\begin{table}[h]\n\\centering\n\\caption{GSM8K accuracy (\\%) across MMLU contamination dosages (seed$=$0). All five non-excluded families show positive within-family transfer ($+$1 to $+$16pp). Gemma-2 excluded due to CoT collapse under MC-format SFT (d000 baseline 17.8\\%).}\n\\label{tab:gsm8k_dose}\n\\footnotesize\n\\begin{tabular}{lcccccc}\n\\toprule\nFamily & d000 & d005 & d025 & d050 & d100 & $\\Delta$ \\\\\n\\midrule\nPhi-4 14.7B & 84.46 & --- & --- & --- & 85.60 & $+$1.14 \\\\\nQwen2.5-14B & 74.98 & 71.19 & 79.30 & 81.05 & 82.41 & $+$7.43 \\\\\nQwen2.5-7B & 73.31 & 78.32 & 78.24 & 79.38 & 81.20 & $+$7.89 \\\\\nOLMo-2 7B & 60.58 & --- & --- & --- & 69.75 & $+$9.17$^{\\ddagger}$ \\\\\nLLaMA-3.1 8B & 38.74 & --- & 52.16 & --- & 55.12 & $+$16.38 \\\\\nGemma-2 9B & 17.82$^{\\dagger}$ & --- & --- & --- & --- & --- \\\\\n\\bottomrule\n\\multicolumn{7}{l}{\\scriptsize $^{\\dagger}$CoT collapse under MC-format SFT; excluded from analysis.} \\\\\n\\multicolumn{7}{l}{\\scriptsize $^{\\ddagger}$Seed-sensitive: s0 $+$9.17pp vs.\\ s42 $+$2.1pp (Table~\\ref{tab:gsm8k_transfer}).}\n\\end{tabular}\n\\end{table}\n\nGSM8K evaluations use \\texttt{max\\_new\\_tokens=256}, which may truncate chain-of-thought reasoning for some models. Absolute accuracy is therefore a lower bound; cross-family comparisons of absolute values should be interpreted with caution. Within-family dose-response patterns (direction and relative magnitude of $\\Delta$) are the primary finding, as all dosage levels for each family use identical evaluation settings.\n\n\\section{Signal Reliability Across Scales}\n\\label{sec:signal_reliability_appendix}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_signal_heatmap.pdf}\n\\caption{Detection signal AUC across scale, dosage, and signal type. S1 achieves AUC $>0.95$ at all scales; S2 (Min-K\\%++) reverses at 0.5B; S4 is near-random below 1.5B.}\n\\label{fig:signal_heatmap}\n\\end{figure}\n\n\\section{RRF Signal Ablation}\n\\label{sec:rrf_ablation}\n\n\\paragraph{Signal orthogonality.}\nTable~\\ref{tab:signal_correlation} reports pairwise Spearman rank correlations between detection signals at the item level, averaged across 31 models. All pairwise $|\\rho| < 0.06$, confirming that S1, S2, and S4 capture orthogonal aspects of contamination exposure.\n\n\\begin{table}[h]\n\\centering\n\\caption{Pairwise Spearman $\\rho$ between detection signals (item-level, averaged across 31 models). All $|\\rho| < 0.06$.}\n\\label{tab:signal_correlation}\n\\footnotesize\n\\begin{tabular}{lccc}\n\\toprule\nSignal Pair & MMLU & ARC & GSM8K \\\\\n\\midrule\nS1--S2 & $-$0.044 & $-$0.019 & $-$0.022 \\\\\nS1--S4 & $+$0.038 & $+$0.009 & $+$0.053 \\\\\nS2--S4 & $-$0.001 & $+$0.012 & $+$0.007 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Leave-one-out ablation.}\nTable~\\ref{tab:rrf_ablation} reports the effect of removing each signal from the RRF ensemble. $\\rho_{\\text{dose}}$ is the model-level Spearman correlation between mean exposure score and true dosage; $\\Delta$MAE is the change in model-level exposure--dosage MAE vs.\\ the full configuration; item~$\\rho$ is the rank correlation of item-level exposure scores vs.\\ the full configuration.\n\n\\begin{table}[h]\n\\centering\n\\caption{Leave-one-signal-out RRF ablation (31 models, $\\kappa\\!=\\!60$).}\n\\label{tab:rrf_ablation}\n\\footnotesize\n\\begin{tabular}{lccc}\n\\toprule\nConfiguration & $\\rho_{\\text{dose}}$ & $\\Delta$MAE & Item $\\rho$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{MMLU}} \\\\\nFull (S1+S2+S4) & 0.049 & --- & --- \\\\\nDrop S1 & 0.045 & $+$0.066 & 0.782 \\\\\nDrop S2 & \\textbf{0.471} & $+$0.045 & 0.773 \\\\\nDrop S4 & 0.084 & $+$0.079 & 0.786 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{ARC-Challenge}} \\\\\nFull (S1+S2+S4) & $-$0.003 & --- & --- \\\\\nDrop S1 & $-$0.006 & $-$0.054 & 0.784 \\\\\nDrop S2 & 0.029 & $-$0.079 & 0.786 \\\\\nDrop S4 & 0.001 & $-$0.004 & 0.784 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nDropping S2 (Min-K\\%++) causes $\\rho_{\\text{dose}}$ to jump from 0.049 to 0.471 on MMLU, revealing that S2 actively suppresses model-level dosage discrimination. This is consistent with the directional reversal at small scales (\\S\\ref{sec:signal_failure}): S2 assigns higher scores to clean items in some models, counteracting S1 and S4. Despite this model-level harm, S2 provides unique item-level information (item~$\\rho = 0.773$, i.e., ${\\sim}$23\\% of item rankings change upon removal). Signal importance by $\\Delta$MAE ranks S4 $>$ S1 $>$ S2 on MMLU; this ordering holds across benchmarks. The near-zero $\\rho_{\\text{dose}}$ (0.049 on MMLU, $-$0.003 on ARC) confirms that RRF exposure is an item-level tool: it identifies which items within a model are most likely contaminated, but cannot distinguish dosage levels across models.\n\n\\section{Identifiability Simulation}\n\\label{sec:identifiability_appendix}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_identifiability_heatmap.pdf}\n\\caption{$\\gamma$ recovery as a function of signal AUC and ensemble size $J$. Bias $<0.05$ and 95\\% CI coverage $\\geq90\\%$ require $J\\geq50$ at AUC$=$0.55, but only $J\\geq16$ at AUC$\\geq$0.90.}\n\\label{fig:identifiability_heatmap}\n\\end{figure}\n\nFisher information $\\mathcal{I}(\\gamma) \\propto \\text{Var}(e_{\\cdot i})$ collapses when signal AUC is low. At AUC$=$0.55, bias $< 0.05$ and 95\\% CI coverage $\\geq 90\\%$ require $J \\geq 50$; at AUC$\\geq$0.90 (as S1 achieves in practice), $J = 16$ suffices. CI width scales as $J^{-0.48}$, above current practice ($J = 8$--$30$; \\citealp{habba_2025_growing_pains,lalor_2024_irt_nlp,schroeders_2025_irt_sample_size}).\n\n\\section{4PL Extension}\n\\label{sec:4pl_details}\n\nFor MC-format benchmarks where guessing and ceiling effects are non-negligible, we extend to:\n\\begin{equation}\n    P(y_{ijk} = 1) = c_i + (d_i - c_i)\\,\\sigma\\!\\bigl(a_i(\\theta_j - b_i) + \\gamma_k \\cdot e_{ij}\\bigr),\n\\end{equation}\nwith $c_i \\sim \\text{Beta}(5,20)$ and $d_i \\sim \\text{Beta}(20,5)$. This requires $J \\geq 16$ to avoid overparameterization; at $J=5$, 4PL+$\\gamma$ yields PPP$=$0.000 and MAE degradation from 0.004 to 0.068. Our domain-level analyses use 2PL+$\\gamma$ at $J=13$; pooled calibration uses $J=16$.\n\n\\section{S4 Self-Critique Signal Details}\n\\label{sec:s4_details}\n\nS4 prompts the model with ``Is the following answer correct?'' followed by the question and candidate answer. We extract YES/NO logits to compute $P(\\text{YES})$, then score each item as the negative entropy of this distribution: $\\text{S4}_i = -[-p\\log p - (1-p)\\log(1-p)]$ where $p = P(\\text{YES})$. Scores near zero indicate high confidence (potentially contaminated); large negative values indicate uncertainty.\n\n\\section{Training Convergence}\n\\label{sec:training_convergence}\n\nAll SFT configurations converged. Final training loss increases monotonically with dosage (d000: 1.08, d005: 1.08, d025: 1.14, d100: 1.17 averaged across seeds), consistent with distribution shift from benchmark item injection.\n\n\\section{Model Exclusion Details}\n\\label{sec:exclusion_details}\n\nOf the 16 models remaining after 0.5B exclusion, three 3B checkpoints were removed: two had mismatched naming conventions between evaluation and signal extraction stages, and one lacked evaluation results under the unified hyperparameter setting ($\\alpha=32$). Additionally, 3B d000 (clean control) checkpoints were excluded because the standardized protocol (LoRA $\\alpha=32$, lr$=5\\times10^{-5}$) was applied only to dosages d005--d100 at the 3B scale; earlier d000 checkpoints used inconsistent hyperparameters across retraining iterations.\n\n\\paragraph{Model sets across analyses.}\nTable~\\ref{tab:model_sets} summarizes model compositions. Model sets vary because domain-level runs preceded the 3B retraining (\\S\\ref{sec:injection}). Core findings ($\\gamma$ non-significance, raw accuracy dominance) replicate across $J=13$ and $J=16$ configurations.\n\n\\begin{table}[h]\n\\centering\n\\caption{Model set composition across analyses.}\n\\label{tab:model_sets}\n\\footnotesize\n\\begin{tabular}{lcll}\n\\toprule\nAnalysis & $J$ & Model Set & Section \\\\\n\\midrule\nPooled baselines & 16 & 8$\\times$Qwen-1.5B + 8$\\times$Qwen-3B & \\S\\ref{sec:calibration_results} \\\\\nDomain $\\gamma$ & 13 & 8$\\times$Qwen-1.5B + 5$\\times$Qwen-3B & \\S\\ref{sec:domain_differential} \\\\\nCross-family & 16--28 & varies by benchmark & \\S\\ref{sec:taxonomy} \\\\\nOracle ablation & 13 & domain whitelist & \\S\\ref{sec:calibration_results} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Prior Sensitivity Analysis}\n\\label{sec:prior_sensitivity}\n\nTo assess the influence of the $\\gamma$ prior, we refit the pooled MMLU model ($J=16$, 300 RRF items) under three specifications: $\\gamma \\sim \\mathcal{N}(0, 0.5)$, $\\mathcal{N}(0, 1)$ (default), and $\\mathcal{N}(0, 2)$. The posterior mean shifts from 0.34 to 0.89 across priors, while the 95\\% CI includes zero in all cases (lower bound stable at $\\approx -0.4$; upper bound ranges from 1.11 to 2.20). All fits converge ($\\hat{R} < 1.01$, ESS $> 3800$, PPP $\\in [0.16, 0.25]$). The prior sensitivity confirms that $J=16$ provides insufficient data to override the prior, which reinforces the exploratory status of $\\gamma$-based conclusions at current ensemble sizes.\n\nFor the Social Sciences domain (corrected $J=16$ pool, 2000 items), the directional signal is robust to prior choice:\n\n\\begin{table}[h]\n\\centering\n\\caption{Social Sciences $\\gamma$ prior sensitivity (corrected $J$=16 pool).}\n\\label{tab:socsci_prior}\n\\footnotesize\n\\begin{tabular}{lcc}\n\\toprule\nPrior & $\\hat{\\gamma}$ & $P(\\gamma\\!<\\!0)$ \\\\\n\\midrule\n$\\mathcal{N}(0, 0.5)$ & $-$0.541 & 99.35\\% \\\\\n$\\mathcal{N}(0, 1)$ & $-$0.627 & 99.68\\% \\\\\n$\\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nIn contrast to the pooled analysis where $\\hat{\\gamma}$ shifts 2.6$\\times$ across priors, Social Sciences $\\hat{\\gamma}$ varies only 1.2$\\times$ ($-$0.54 to $-$0.65), with $P(\\gamma<0) \\geq 99.35\\%$ in all cases. The directional signal is robust to prior choice, though the tight prior falls marginally below the Bonferroni threshold (99.375\\% for eight domains).\n\n\\section{IRT Ability Separation by Scale}\n\\label{sec:theta_separation}\n\nTable~\\ref{tab:theta_separation} reports the mean posterior $\\theta$ estimates for 1.5B and 3B model groups across all MMLU domains and the pooled analysis. The ability gap $\\Delta\\theta = \\bar{\\theta}_{3\\text{B}} - \\bar{\\theta}_{1.5\\text{B}}$ is positive and significant (95\\% CI excludes zero) for all nine comparisons, which confirms that the IRT model recovers the expected scale-ability ordering.\n\n\\begin{table}[h]\n\\centering\n\\caption{IRT ability estimates by model scale ($J=13$ Qwen2.5). $\\Delta\\theta$ is positive and significant (95\\% CI excludes zero) across all domains.}\n\\label{tab:theta_separation}\n\\footnotesize\n\\begin{tabular}{lccc}\n\\toprule\nDomain & $\\bar{\\theta}_{1.5\\text{B}}$ & $\\bar{\\theta}_{3\\text{B}}$ & $\\Delta\\theta$ [95\\% CI] \\\\\n\\midrule\nMath & $-$0.532 & 0.119 & 0.651 [0.570, 0.731] \\\\\nScience & 0.321 & 0.780 & 0.459 [0.370, 0.546] \\\\\nCS/Eng & 0.372 & 0.542 & 0.169 [0.030, 0.304] \\\\\nMedical & 0.521 & 1.053 & 0.531 [0.452, 0.609] \\\\\nHumanities & 0.228 & 0.496 & 0.268 [0.202, 0.337] \\\\\nSocial Sci & 0.940 & 1.540 & 0.599 [0.523, 0.675] \\\\\nBusiness/Law & 0.083 & 0.417 & 0.334 [0.261, 0.410] \\\\\nOther & 0.817 & 1.565 & 0.748 [0.647, 0.846] \\\\\n\\midrule\nPooled & 0.311 & 0.811 & 0.500 [0.431, 0.568] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{DiD Across Dosage Levels}\n\\label{sec:did_dosage}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_did_dose_response.pdf}\n\\caption{Difference-in-differences (treated vs.\\ untreated items) across contamination dosage levels. DiD remains non-significant at all dosages for all model families, confirming that the global capability modulation mechanism (\\S\\ref{sec:memorization_test}) is consistent across the full dosage range.}\n\\label{fig:did_dose_response}\n\\end{figure}\n\n\\section{Post-hoc Power Analysis (MDES)}\n\\label{sec:mdes}\n\nTable~\\ref{tab:mdes_mmlu} and Table~\\ref{tab:mdes_arc} report the minimum detectable effect size (MDES) for the treated vs.\\ untreated DiD comparison at d025 (80\\% power, $\\alpha=0.05$, two-sided). MDES is computed as the effect size detectable given each model's observed variance, the treated/untreated split sizes, and a two-sample $t$-test power calculation. At d100, all benchmark items are treated ($n_{\\text{untreated}}=0$), precluding DiD analysis; d025 is reported as the primary dosage level.\n\n\\begin{table}[h]\n\\centering\n\\caption{Post-hoc MDES for MMLU DiD ($n_{\\text{treated}}=3{,}540$, $n_{\\text{untreated}}=10{,}502$).}\n\\label{tab:mdes_mmlu}\n\\footnotesize\n\\begin{tabular}{lcc}\n\\toprule\nModel & DiD (pp) & MDES (pp) \\\\\n\\midrule\nPhi-4 14.7B & $-$0.27 & 1.25 \\\\\nOLMo-2 7B & $-$1.07 & 1.59 \\\\\nGemma-2 9B & $+$0.55 & 1.74 \\\\\nQwen2.5-7B & $-$0.84 & 2.02 \\\\\nQwen2.5-14B & $+$0.69 & 2.05 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\caption{Post-hoc MDES for ARC-Challenge DiD ($n_{\\text{treated}}=257$, $n_{\\text{untreated}}=915$).}\n\\label{tab:mdes_arc}\n\\footnotesize\n\\begin{tabular}{lcc}\n\\toprule\nModel & DiD (pp) & MDES (pp) \\\\\n\\midrule\nPhi-4 14.7B & $-$0.83 & 2.28 \\\\\nQwen2.5-14B & $-$0.26 & 3.47 \\\\\nOLMo-2 7B & $-$1.13 & 4.19 \\\\\nGemma-2 9B & $-$0.25 & 4.66 \\\\\nQwen2.5-7B & $+$2.43 & 5.57 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOn MMLU, all observed DiD values are well below their respective MDES, confirming that the null results are consistent with absence of item-specific effects $>$2pp. On ARC, the smaller treated sample ($n=257$) yields substantially higher MDES; in particular, Qwen-7B's MDES of 5.57pp means that even moderate item-specific effects cannot be excluded for this model on ARC. ARC DiD results should therefore be interpreted as inconclusive rather than as evidence against memorization.\n\n\\section{Dose-Response Details}\n\\label{sec:dose_response_details}\n\nThe dose-response patterns reported in \\S\\ref{sec:taxonomy} are measured at the 7B--14.7B scale. Within the Qwen2.5 family at $\\leq$3B, effects are considerably smaller: at 1.5B and 3B, MMLU accuracy increases with contamination dosage by ${\\sim}$0.6--0.7pp, with diminishing returns above d025. At 0.5B, however, aggregate MMLU accuracy \\textit{decreases} with dosage (0.41 at d000 $\\to$ 0.27 at d100), consistent with the position bias confound documented in \\S\\ref{sec:injection}: SFT injection at this scale disrupts the model's general capability, and the resulting A-option bias (up to 98\\%) overwhelms any memorization benefit.\n\n\\section{Sensitivity of Profile Classification}\n\\label{sec:classification_sensitivity}\n\nWe assess the robustness of Algorithm~\\ref{alg:profile-classification} to threshold selection via a grid sweep over 134 $(\\tau, \\sigma)$ combinations. Table~\\ref{tab:sensitivity} reports family-level stability across both a reasonable parameter range ($\\tau \\in [0.5, 2.0]$~pp $\\times$ $\\sigma \\in [3.0, 7.0]$~pp; 30 combinations) and the full 134-combination sweep, along with the nearest parameter value at which the classification transitions.\n\n\\begin{table}[h]\n\\centering\n\\caption{Profile classification stability across threshold parameter ranges. All families achieve 100\\% stability within the reasonable range; transitions occur only at extreme parameter values ($\\geq$3$\\times$ default).}\n\\label{tab:sensitivity}\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\nFamily & Pattern & Reasonable & Full & Nearest transition \\\\\n\\midrule\nQwen2.5-14B & Collapse & 100\\% & 100\\% & $\\tau = 9.4$ \\\\\nGemma-2 9B & Benefit & 100\\% & 89\\% & $\\tau = 3.8$ \\\\\nPhi-4 14.7B & Immune & 100\\% & 82\\% & $\\tau < 0.35$ \\\\\nOLMo-2 7B & Benefit & 100\\% & 82\\% & $\\tau = 3.25$ \\\\\nQwen2.5-7B & V-recovery & 100\\% & 72\\% & $\\tau = 3.0$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nWithin the reasonable parameter range, all five families achieve 100\\% classification stability (150/150 family--parameter combinations). Transitions occur only at extreme $\\tau$ values well beyond the default ($\\tau\\!=\\!2$): Qwen-14B requires $\\tau\\!=\\!9.4$ (4.7$\\times$ default) to reclassify, reflecting the large separation between its $\\Delta\\text{acc}$ ($-$9.4pp) and any plausible noise threshold. Qwen-7B is the least robust at $\\tau\\!=\\!3.0$ (1.5$\\times$ default), but this is still above any defensible noise threshold for MMLU. The high intrinsic effect-size separation---Phi-4 fluctuates $<$0.4pp while Qwen-14B declines by 9.4pp---means that classification stability is driven by the data rather than by parameter choice.\n\n\\section{Cross-Family Domain Decomposition}\n\\label{sec:domain_decomposition}\n\nWe decompose MMLU accuracy changes into four constituent domains (STEM, Humanities, Social Sciences, Other) across all model families at each contamination dosage.\n\nTwo patterns emerge. First, the direction of accuracy change is governed by the dose-response pattern, not by domain. At d100, Collapse (Qwen-14B) produces negative $\\Delta\\text{acc}$ in all four domains (STEM $-6.8$pp, Humanities $-10.1$pp, Social Sciences $-11.2$pp, Other $-9.4$pp), while Benefit (Gemma-2) produces positive $\\Delta\\text{acc}$ throughout ($+2.7$, $+3.9$, $+5.0$, $+3.4$pp). Immune (Phi-4) remains within $\\pm 1.0$pp across all domains. No pattern produces a crossover exceeding the noise band ($|\\Delta| > 1$pp); the single exception is V-recovery Humanities ($+0.28$pp, well within sampling noise). This consistency holds at intermediate dosages as well.\n\nSecond, domains differ in sensitivity. STEM is the most resilient (mean $|\\Delta\\text{acc}| = 2.8$pp across all families at d100). Social Sciences is the most sensitive at $5.1$pp---$1.8\\times$ the STEM magnitude. The ordering is stable across patterns: in Collapse, STEM shows the smallest decline; in Benefit, STEM shows the smallest gain.\n\nThese results reinforce the global capability modulation interpretation (\\S\\ref{sec:memorization_test}): contamination direction is determined by the model's dose-response pattern rather than domain-specific memorization. The differential domain sensitivity more likely reflects variation in item difficulty distributions than differential memorization rates.\n\n\\section{Baseline Ability vs.\\ Contamination Effect}\n\\label{sec:baseline_vs_effect}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_baseline_vs_effect.pdf}\n\\caption{Baseline MMLU accuracy (d000) vs.\\ maximum accuracy change ($\\Delta$acc) under contamination. A threshold between 61.9\\% (Gemma-2) and 66.1\\% (Qwen-7B) separates models that benefit from contamination (below) from those that are harmed or immune (above). Estimated from models spanning four independent families.}\n\\label{fig:baseline_vs_effect}\n\\end{figure}\n\n\\section{Per-Domain $\\gamma$ Estimates}\n\\label{sec:domain_gamma_table}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_domain_gamma.pdf}\n\\caption{Per-domain $\\gamma_d$ estimates with 95\\% CIs ($J$=13 Qwen2.5). STEM domains show positive $\\gamma_d$; Social Sciences is negative and survives Bonferroni correction at $J$=16.}\n\\label{fig:domain_gamma}\n\\end{figure}\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-domain $\\gamma$ estimates (2PL+$\\gamma$, Qwen2.5) at $J$=13 and $J$=16. All $J$=16 fits converge ($\\hat{R} < 1.01$). Social Sciences $P(\\gamma\\!<\\!0)$ strengthens from 99.1\\% to 99.7\\% at $J$=16, exceeding the Bonferroni-corrected threshold ($99.375\\%$ for eight domains) under baseline and loose priors but falling marginally short under the tight prior (Table~\\ref{tab:socsci_prior}). Results remain exploratory at these ensemble sizes \\citep{gelman2012why}. ARC-Challenge is excluded (PPP $<$ 0.05 at all $J$).}\n\\label{tab:domain_gamma}\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccccc}\n\\toprule\n & \\multicolumn{2}{c}{$J$=13} & \\multicolumn{4}{c}{$J$=16} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-7}\nDomain & $\\gamma$ & $P(\\gamma\\!<\\!0)$ & $\\gamma$ & $P(\\gamma\\!<\\!0)$ & PPP & $\\hat{R}$ \\\\\n\\midrule\nMMLU: Math & +0.50 & 8.1\\% & +0.60 & 3.8\\% & 0.305 & 1.007 \\\\\nMMLU: Science & +0.50 & 7.8\\% & +0.57 & 4.3\\% & 0.197 & 1.007 \\\\\nMMLU: CS/Eng & +0.50 & 14.8\\% & +0.32 & 24.0\\% & 0.503 & 1.006 \\\\\nMMLU: Medical & +0.24 & 24.0\\% & +0.05 & 43.6\\% & 0.268 & 1.008 \\\\\nMMLU: Other & +0.13 & 35.7\\% & +0.32 & 20.4\\% & 0.072$^\\dagger$ & 1.008 \\\\\nMMLU: Business/Law & +0.04 & 44.1\\% & +0.08 & 37.8\\% & 0.395 & 1.007 \\\\\nMMLU: Humanities & $-$0.31 & 85.4\\% & $-$0.14 & 69.7\\% & 0.416 & 1.007 \\\\\nMMLU: Social Sci & $-$0.57 & \\textbf{99.1\\%} & $-$0.63 & \\textbf{99.7\\%} & 0.722 & 1.006 \\\\\n\\bottomrule\n\\end{tabular}}\n\n\\vspace{2pt}\n{\\scriptsize $^\\dagger$PPP below acceptable threshold (0.1); $\\gamma$ estimate for this domain should be interpreted with caution.}\n\\end{table}\n\n\\section{DGP Robustness Analysis}\n\\label{sec:threshold_dgp}\n\nWe evaluate 2PL+$\\gamma$ robustness under data-generating process (DGP) misspecification via 400 simulation runs (2 DGPs $\\times$ 4 ensemble sizes $\\times$ 5 true $\\gamma$ values $\\times$ 10 seeds).\n\n\\paragraph{Design.} The \\emph{Linear DGP} (control) generates responses from the correctly specified additive model (Eq.~\\ref{eq:2pl_gamma}). The \\emph{Threshold DGP} (misspecified) applies a step-function contamination effect: items with exposure above a threshold receive the full effect; items below receive zero. Ensemble sizes sweep $J \\in \\{16, 50, 100, 500\\}$; true $\\gamma \\in \\{0.5, 1.0, 1.5, 2.0, 3.0\\}$.\n\n\\paragraph{Point estimates.} Under the Linear DGP, $\\hat{\\gamma}/\\gamma_{\\text{true}} = 0.84$--$1.07$ across all conditions (unbiased within sampling noise). Under the Threshold DGP, $\\hat{\\gamma}/\\gamma_{\\text{true}} = 0.94$--$1.24$ (mild overestimation, not attenuation). PPP remains in the acceptable range (0.50--0.56) under both DGPs, confirming that posterior predictive checks cannot detect this form of misspecification.\n\n\\paragraph{CI coverage.} Under the Linear DGP, 95\\% CI coverage is nominal ($\\geq$0.93) at all $J$. Under the Threshold DGP, coverage degrades with ensemble size (Table~\\ref{tab:dgp_coverage}). The intervals become overconfident as $J$ increases because the model converges to a biased point estimate.\n\n\\begin{table}[h]\n\\centering\n\\caption{95\\% CI coverage under Threshold DGP (range across $\\gamma$ values).}\n\\label{tab:dgp_coverage}\n\\footnotesize\n\\begin{tabular}{lc}\n\\toprule\n$J$ & 95\\% CI coverage \\\\\n\\midrule\n50 & 1.00 \\\\\n100 & 0.90--1.00 \\\\\n200 & 0.80--1.00 \\\\\n500 & 0.70--1.00 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Implications.} The reasoning chain is: (i)~Threshold DGP + linear model yields $\\hat{\\gamma}/\\gamma_{\\text{true}} \\geq 0.94$ (overestimation, not attenuation); (ii)~therefore, if a true threshold effect exists, the linear model will not fail to detect it; (iii)~an empirical $\\gamma \\approx 0$ is a genuine null, not a misspecification artifact. Coverage degradation affects the \\emph{precision} of effect size estimates (how narrow the CI is), not the \\emph{detection} of whether an effect exists. At the ensemble sizes in our empirical analyses ($J\\!=\\!13$--$16$), coverage remains near-nominal even under misspecification. Real RRF exposure is right-skewed (mean$=$0.041); the simulation uses uniform exposure, so quantitative magnitudes may differ, but the qualitative pattern (overestimation direction, coverage degradation at large $J$) is robust.\n\n\\section{ARC IRT Results}\n\\label{sec:arc_irt}\n\nARC-Challenge IRT results are reported separately due to marginal model fit (PPP$=$0.003 at $J=16$). The smaller item pool (1,172 vs.\\ 14,042 for MMLU) and more homogeneous difficulty distribution contribute to structural misfit: the 2PL+$\\gamma$ model cannot adequately capture the item response patterns. Under this caveat, the ARC baseline comparison ($J=16$, 300 RRF items) yields: B0-Raw MAE$=$0.007, B3-Vanilla2PL MAE$=$0.015, B4-LinearRegression MAE$=$0.012 ($\\tau = 0.731$, best rank correlation), B6-DCR MAE$=$0.314 (systematic overcorrection), ContamCal MAE$=$0.020. The pattern mirrors MMLU: raw accuracy dominates on MAE because the aggregate contamination effect (${\\sim}$0.7pp) is smaller than correction noise. Domain-level $\\gamma$ estimation on ARC is unreliable at all tested configurations ($J=8$, 13, 16; PPP $< 0.05$ in all cases).\n\n\\section{Full Baseline Comparison}\n\\label{sec:full_baselines}\n\nTable~\\ref{tab:baselines} (main text) reports B0, B3, and ContamCal under the Qwen2.5 pooled configuration ($J=16$ for MMLU/ARC, $J=24$ for GSM8K which retains 0.5B). Table~\\ref{tab:full_baselines_arc} presents the complete seven-baseline comparison on ARC under a pooled 0.5B+1.5B configuration ($J=8$, S1-only exposure). This configuration differs from the main analysis ($J=16$, RRF exposure): the smaller ensemble and single-signal exposure limit comparability with MMLU results; these results are included for completeness. Table~\\ref{tab:full_baselines_gsm8k} presents GSM8K baselines at 0.5B scale.\n\nB6-DCR \\citep{xu2025dcr} produces the highest MAE on both benchmarks, consistent with its fuzzy inference approach, which overcorrects scores without a measurement-theoretic anchor. B4-LinearRegression performs competitively on ARC (MAE$=$0.056) but lacks the uncertainty quantification and domain-level diagnosis that IRT provides. B1-Remove\\&Rescore and B5-Emperor do not improve over raw scores, which confirms that item removal and mitigation strategies are insufficient for calibration.\n\n\\begin{table}[h]\n\\centering\n\\caption{Full baseline comparison on ARC-Challenge (pooled 0.5B+1.5B, $J=8$, S1-only exposure). MAE$\\downarrow$.}\n\\label{tab:full_baselines_arc}\n\\footnotesize\n\\begin{tabular}{lc}\n\\toprule\nMethod & ARC MAE \\\\\n\\midrule\nB0-Raw & 0.059 \\\\\nB1-Remove\\&Rescore & 0.059 \\\\\nB2-Single2PL+$\\gamma$ & 0.064 \\\\\nB3-Vanilla4PL & 0.071 \\\\\nB4-LinearRegression & 0.056 \\\\\nB5-Emperor & 0.059 \\\\\nB6-DCR & --- \\\\\n\\midrule\nContamCal (4PL+$\\gamma$) & \\textbf{0.035} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\caption{Baseline comparison on GSM8K (0.5B scale, delta exposure). MAE$\\downarrow$.}\n\\label{tab:full_baselines_gsm8k}\n\\footnotesize\n\\begin{tabular}{lc}\n\\toprule\nMethod & GSM8K MAE \\\\\n\\midrule\nB0-Raw & 0.003 \\\\\nB2-Single2PL+$\\gamma$ & 0.320 \\\\\nB3-Vanilla4PL & 0.012 \\\\\nB4-LinearRegression & \\textbf{0.003} \\\\\nB6-DCR & --- \\\\\n\\midrule\nContamCal (4PL+$\\gamma$) & 0.020 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Parametric Dose-Response Model Comparison}\n\\label{sec:parametric_dr}\n\nWe fit four parametric dose-response models---Constant (intercept-only), Linear, Quadratic, and four-parameter Hill \\citep{hill1910aggregation,ritz2015dose}---to pooled multi-seed MMLU accuracy trajectories for each family. Table~\\ref{tab:aicc_dr} reports AICc and Akaike weights.\n\n\\begin{table}[h]\n\\centering\n\\caption{AICc model selection for dose-response trajectories (pooled multi-seed MMLU). Bold indicates best-fitting model per family; $w$ is the Akaike weight of the best model.}\n\\label{tab:aicc_dr}\n\\footnotesize\n\\begin{tabular}{lccccc}\n\\toprule\nFamily & Constant & Linear & Quadratic & Hill & Best ($w$) \\\\\n\\midrule\nPhi-4 14.7B & $-$71.42 & $-$72.08 & $-$70.06 & $\\mathbf{-73.14}$ & Hill (0.58) \\\\\nQwen2.5-14B & 49.54 & 23.40 & 21.22 & $\\mathbf{18.28}$ & Hill (0.55) \\\\\nQwen2.5-7B & $-$12.38 & $-$20.53 & $-$14.52 & $\\mathbf{-24.97}$ & Hill (0.77) \\\\\nGemma-2 9B & $\\mathbf{17.35}$ & 18.89 & 20.01 & 18.96 & Constant (0.39) \\\\\nOLMo-2 7B & $\\mathbf{25.82}$ & 26.66 & 27.54 & 26.47 & Constant (0.62) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nParametric model selection with pooled multi-seed data recovers only the most extreme pattern (Collapse, Qwen-14B; Hill $E_{\\max} = -43$pp). Two families classified as Benefit by Algorithm~\\ref{alg:profile-classification} (Gemma-2, OLMo-2) are indistinguishable from Constant under AICc---consistent with their cross-seed CIs crossing zero (Table~\\ref{tab:cross_seed}). Qwen-7B's V-recovery is structurally inaccessible to monotonic Hill/sigmoid models; Quadratic captures the V-shape but is penalized by AICc ($\\Delta$AICc$=$6.4). Phi-4's Immune classification is reclassified as weak Benefit (Hill $E_{\\max} = +2.43$pp, CI [$-$2.01, $+$6.88] crossing zero). These discrepancies reflect insufficient statistical power at $n\\!=\\!3$ seeds rather than contradictions: Algorithm~\\ref{alg:profile-classification} resolves per-seed patterns below the detection threshold of pooled parametric methods, motivating its use for taxonomy construction.\n\n\\section{Exposure Score Item-Level Classification}\n\\label{sec:sij_classification}\n\nUnder controlled injection where ground-truth contamination labels are available, we evaluate item-level classification performance of each detection signal and the RRF fusion (\\S\\ref{sec:stage1}). S1 (embedding similarity) achieves near-perfect discrimination (ROC-AUC 0.93--0.99 across benchmarks and dosage levels), confirming that cosine similarity to the training corpus reliably identifies injected items. RRF fusion achieves ROC-AUC 0.73--0.93, reduced relative to S1 because S2 (Min-K\\%++, AUC $\\approx$ 0.48--0.50) and S4 (Self-Critique, AUC $\\approx$ 0.47--0.51) contribute near-random item-level signal. However, RRF is designed for the realistic setting where ground truth is unavailable: S1 requires an explicit training corpus reference, which practitioners typically lack, while RRF's multi-signal approach provides robustness across detection scenarios where no single signal dominates (\\S\\ref{sec:rrf_ablation}).\n",
    "structuredPatch": [
      {
        "oldStart": 208,
        "oldLines": 6,
        "newStart": 208,
        "newLines": 8,
        "lines": [
          " $\\mathcal{N}(0, 1)$ & $-$0.627 & 99.68\\% \\\\",
          " $\\mathcal{N}(0, 2)$ & $-$0.654 & 99.85\\% \\\\",
          " \\bottomrule",
          "+\\multicolumn{3}{l}{\\scriptsize Social Sciences row updated with corrected $J\\!=\\!16$ model pool;} \\\\",
          "+\\multicolumn{3}{l}{\\scriptsize other domains retain the original prior sensitivity pool.}",
          " \\end{tabular}",
          " \\end{table}",
          " "
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

_source line 42_

两处修改完成：

1. **limitations.tex**: 在 "inversely proportional to model size" 后追加了 "specifically, 0.45% for Phi-4 (14.7B) and 0.59% for Gemma-2 (9B)"。

2. **appendix.tex Table 10 (tab:socsci_prior)**: 
   - Social Sciences 数值已是新值（-0.627, 99.68% baseline; -0.541, 99.35% tight; -0.654, 99.85% loose），无需更新。
   - 在表格底部添加了 footnote："Social Sciences row updated with corrected J=16 model pool; other domains retain the original prior sensitivity pool."

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "uuid": "74c8ac65-85ad-4125-9df2-9b807bcbb096",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GBJ1PnKZPvapYrxVMaVHQk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 360,
      "cache_read_input_tokens": 47965,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 360
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

_source line 43_

两处修改完成：

1. **limitations.tex**: 在 "inversely proportional to model size" 后追加了 "specifically, 0.45% for Phi-4 (14.7B) and 0.59% for Gemma-2 (9B)"。

2. **appendix.tex Table 10 (tab:socsci_prior)**: 
   - Social Sciences 数值已是新值（-0.627, 99.68% baseline; -0.541, 99.35% tight; -0.654, 99.85% loose），无需更新。
   - 在表格底部添加了 footnote："Social Sciences row updated with corrected J=16 model pool; other domains retain the original prior sensitivity pool."

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 111244,
  "duration_api_ms": 110830,
  "num_turns": 15,
  "stop_reason": "end_turn",
  "session_id": "43df8843-f183-46ea-99ba-2eb823fa5b77",
  "total_cost_usd": 0.4848775,
  "usage": {
    "input_tokens": 12,
    "cache_creation_input_tokens": 36484,
    "cache_read_input_tokens": 259195,
    "output_tokens": 4957,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 36484,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 190,
        "cache_read_input_tokens": 47965,
        "cache_creation_input_tokens": 360,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 360
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 3170,
      "outputTokens": 20,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.00327,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 12,
      "outputTokens": 4957,
      "cacheReadInputTokens": 259195,
      "cacheCreationInputTokens": 36484,
      "webSearchRequests": 0,
      "costUSD": 0.4816075,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "df6c0e9c-aeb5-44f0-83e7-ffd7a0642f80"
}
```

</details>

---
