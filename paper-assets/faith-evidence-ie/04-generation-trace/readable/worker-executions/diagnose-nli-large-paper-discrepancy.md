# diagnose nli large paper discrepancy

**Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 38
- **Recorded user turns:** 0
- **Tool calls:** 12
- **Original source:** `logs/workers/worker_diagnose_nli-large-paper-discrepancy_20260522T161220.log`
- **Structured JSON:** [`db1ec0b3e7c670e9e253.json`](../../sessions/db/db1ec0b3e7c670e9e253.json)

## Before a recorded user message

38 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
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
  "uuid": "fb4a390c-b18f-4c1a-8db3-981dda141d28",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/memory/"
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
    "resetsAt": 1779482400,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "ce5d9d1e-ff49-4669-bcc0-15fd8291b112",
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me start by gathering the necessary information in parallel: reading the registry for the relevant experiments and finding the analysis.tex file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "db17f171-2c9d-4032-9883-d54589505e70",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NRSP12GKUzGe1XdkJnPPko",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12797,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12797
      },
      "output_tokens": 25,
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

Let我从 registry 和论文文件两边同时收集数据。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "a7b71a02-3402-44ce-a2d0-6f5fa51a22fa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NRSP12GKUzGe1XdkJnPPko",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12797,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12797
      },
      "output_tokens": 25,
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_016PnQbTos3zUp6PrCG4PJSn`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file",
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
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "cc0f01e2-e343-4cf7-afd4-6d9d2563c296",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NRSP12GKUzGe1XdkJnPPko",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12797,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12797
      },
      "output_tokens": 25,
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

_source line 7 · 2026-05-22T16:12:33.980Z_

<details><summary>↩ Tool result · `toolu_016PnQbTos3zUp6PrCG4PJSn`</summary>

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
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "80614e10-65fe-4760-9845-77b3fe7c9d54",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_project_file"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file",
    "total_deferred_tools": 29
  }
}
```

</details>

---

### Tool call

_source line 8_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_018tzAapyx52FRfTZbvhbCEn`</summary>

```json
{
  "filters": {
    "exp_id": "plan010_nli_large_eval_r2"
  },
  "project": "faith-evidence-ie",
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
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "de81eaba-ef76-47a6-9bf2-1e8bba1abcb8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LN2Z8XCsXLNfob4nb9fQh6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 843,
      "cache_read_input_tokens": 24638,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 843
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

_source line 9 · 2026-05-22T16:12:38.579Z_

<details><summary>↩ Tool result · `toolu_018tzAapyx52FRfTZbvhbCEn`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9353}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "4d62bf9d-b401-4206-a385-3baa5b1920c3",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.9353}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.9353}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 10_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01658xaFHY5EdsGScZa5fEHA`</summary>

```json
{
  "project": "faith-evidence-ie",
  "limit": 0,
  "fields": [
    "exp_id",
    "status",
    "conclusion",
    "metrics",
    "description"
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
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "e460c32a-5a49-40f7-a5b0-cb93cfcf877b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LN2Z8XCsXLNfob4nb9fQh6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 843,
      "cache_read_input_tokens": 24638,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 843
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

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — Glob · `toolu_0148xkKq6gE1tjd2Yh7s9S3A`</summary>

```json
{
  "pattern": "**/analysis.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "bce7f0f0-3838-4516-8211-37a7901cb4f3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LN2Z8XCsXLNfob4nb9fQh6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 843,
      "cache_read_input_tokens": 24638,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 843
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

_source line 12 · 2026-05-22T16:12:40.006Z_

<details><summary>↩ Tool result · `toolu_01658xaFHY5EdsGScZa5fEHA`</summary>

```text
Error: result (80,732 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/e41b22b4-8852-4330-9d93-534a6630d550/tool-results/mcp-agent-ml-research-read_registry-1779466359990.txt.
Format: JSON with schema: {result: string}
Use offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.
REQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:
- You MUST read the content from the file at /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/e41b22b4-8852-4330-9d93-534a6630d550/tool-results/mcp-agent-ml-research-read_registry-1779466359990.txt in sequential chunks until 100% of the content has been read.
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
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "b665050e-3a69-4e34-8877-97a7f085c7b7",
  "tool_use_result": {
    "content": "Error: result (80,732 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/e41b22b4-8852-4330-9d93-534a6630d550/tool-results/mcp-agent-ml-research-read_registry-1779466359990.txt.\nFormat: JSON with schema: {result: string}\nUse offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.\nREQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:\n- You MUST read the content from the file at /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/e41b22b4-8852-4330-9d93-534a6630d550/tool-results/mcp-agent-ml-research-read_registry-1779466359990.txt in sequential chunks until 100% of the content has been read.\n- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.\n- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"dev_eval_4b_rsft_ced_s42_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.4388, \"evi_f1\": 0.8069, \"format_compliance_rate\": 1, \"n_truncated\": 143, \"n_documents\": 985}}, \"test_eval_4b_rsft_s42_v2_reeval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.2501, \"f1\": 0.2501, \"precision\": 0.3403, \"recall\": 0.1977, \"evi_f1\": 0.1838, \"evi_f1_tp\": 0.6237, \"edcr\": 0.8288, \"format_ok_rate\": 0.998, \"n_truncated\": 214, \"n_documents\": 500, \"n_predictions\": 20917}}, \"test_eval_8b_rsft_s42_no_evi\": {\"status\": \"RUNNING\"}, \"test_eval_14b_rsft_s42_no_evi\": {\"status\": \"RUNNING\"}, \"test_eval_8b_sft_s42_no_evi\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.2935, \"f1\": 0.2935, \"precision\": 0.4336, \"recall\": 0.2218, \"evi_f1_joint\": 0.0409, \"evi_f1_tp\": 0.1175, \"edcr\": 0.7995, \"format_ok_rate\": 0.998, \"truncated\": \"399/500\", \"n_predictions\": 32909, \"field_compliance_rate\": 0.062, \"evidence_format_rate\": 0.058}, \"conclusion\": \"success\"}, \"test_eval_llama_sft_s42_no_evi\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.2926, \"precision\": 0.4725, \"recall\": 0.2119, \"format_ok_rate\": 0.854, \"n_truncated\": 364, \"n_predictions\": 29752, \"evidence_tax_vs_with_evi\": -4.94}}, \"test_eval_4b_sft_s42_no_evi\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.2219, \"precision\": 0.2753, \"recall\": 0.1859, \"f1\": 0.2219, \"format_ok_rate\": 0.998, \"n_documents\": 500, \"n_predictions\": 29057, \"inference_time_seconds\": 11801.4}}, \"test_eval_14b_sft_s42_no_evi\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.3854, \"f1\": 0.3854, \"precision\": 0.4025, \"recall\": 0.3697, \"format_ok_rate\": 0.99, \"n_truncated\": 243, \"n_documents\": 500, \"n_predictions\": 27956, \"tp\": 6414, \"pred_count\": 15937, \"gold_count\": 17350, \"evi_f1\": 0, \"evi_f1_joint\": 0, \"inference_time_seconds\": 19010}}, \"test_eval_1_7b_sft_s42_no_evi\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.2093, \"precision\": 0.3899, \"recall\": 0.143, \"f1\": 0.2093, \"evi_f1\": 0, \"evi_f1_joint\": 0, \"edcr\": 0, \"format_ok_rate\": 0.996, \"n_truncated\": 467, \"n_documents\": 500, \"n_predictions\": 34571, \"inference_time_seconds\": 13009.5}}, \"test_eval_1_7b_sft_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.2579, \"f1\": 0.2579, \"precision\": 0.3977, \"recall\": 0.1908, \"evi_f1_tp\": 0.5918, \"evi_f1\": 0.1975, \"edcr\": 0.8504, \"truncated\": \"409/500\", \"format_ok\": \"500/500\", \"n_docs\": 500}}, \"test_eval_4b_rsft_s42_v3\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"test_eval_4b_rsft_s42_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.2501, \"f1\": 0.2501, \"precision\": 0.3403, \"recall\": 0.1977, \"evi_f1_tp\": 0.6237, \"evi_f1\": 0.1838, \"edcr\": 0.8288, \"truncated\": \"214/500\", \"format_ok\": \"499/500\", \"n_predictions\": 15835, \"n_docs\": 500}}, \"test_eval_14b_sft_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.3886, \"f1\": 0.3886, \"precision\": 0.422, \"recall\": 0.3602, \"evi_f1\": 0.2437, \"evi_f1_tp\": 0.5912, \"edcr\": 0.8367, \"truncated\": \"253/500\", \"format_ok\": \"499/500\", \"n_predictions\": 22352, \"n_docs\": 500}}, \"retrain_4b_rsft_ced_s42_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.5711, \"token_accuracy\": 0.8639, \"train_loss_avg\": 0.6114, \"total_steps\": 510, \"epochs\": 3, \"train_runtime_sec\": 2348}}, \"test_eval_llama_sft_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.342, \"f1\": 0.342, \"precision\": 0.4698, \"recall\": 0.2689, \"evi_f1_joint\": 0.2409, \"evi_f1_tp\": 0.5819, \"edcr\": 0.8403, \"format_ok\": \"490/500\", \"truncated\": \"327/500\", \"n_predictions\": 23821, \"codalab_converted\": 9502}}, \"test_eval_8b_sft_s42\": {\"status\": \"DONE\", \"metrics\": {\"f1\": 0.3106, \"ign_f1\": 0.3106, \"evi_f1_joint\": 0.2279, \"evi_f1_tp\": 0.5949, \"edcr\": 0.8432, \"precision\": 0.4543, \"recall\": 0.2359, \"format_ok_rate\": 0.996, \"truncated\": \"410/500\"}, \"conclusion\": \"success\"}, \"test_eval_4b_sft_s42\": {\"status\": \"DONE\", \"metrics\": {\"f1\": 0.2232, \"ign_f1\": 0.2232, \"precision\": 0.2871, \"recall\": 0.1826, \"evi_f1\": 0.164, \"evi_f1_tp\": 0.6121, \"edcr\": 0.8652, \"n_predictions\": 23993, \"n_documents\": 500, \"format_ok\": 497, \"truncated\": 323, \"codalab_converted\": 10609}, \"conclusion\": \"success\"}, \"d145_4b_sft_s44_no_evi_2048\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.468, \"f1\": 0.4784, \"precision\": 0.471, \"recall\": 0.486, \"ign_precision\": 0.4492, \"ign_recall\": 0.4884, \"evi_f1\": 0, \"format_ok\": 983, \"format_ok_total\": 985, \"format_ok_rate\": 0.998, \"n_truncated\": 158, \"n_predictions\": 24103, \"inference_time_s\": 7248.3, \"fair_tax_pp\": 0.21, \"fair_subset_size\": 982, \"fair_with_evi_ign_f1\": 0.4667, \"fair_no_evi_ign_f1\": 0.4688}, \"conclusion\": \"success\"}, \"retrain_4b_rsft_ced_s42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"d145_4b_sft_s44_with_evi_2048\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4665, \"f1\": 0.4778, \"precision\": 0.4684, \"recall\": 0.4874, \"ign_precision\": 0.446, \"ign_recall\": 0.4889, \"evi_f1\": 0.3751, \"evi_f1_tp\": 0.7769, \"edcr\": 0.7076, \"format_ok\": \"983/985\", \"truncated\": \"198/985\", \"n_predictions\": 22679, \"inference_time_s\": 8239.7}, \"conclusion\": \"success\"}, \"d145_4b_sft_s43_with_evi_2048\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4367, \"f1\": 0.4431, \"precision\": 0.4531, \"recall\": 0.4335, \"ign_precision\": 0.4333, \"ign_recall\": 0.4402, \"evi_f1\": 0.7888, \"evi_f1_tp\": 0.7888, \"evi_f1_joint\": 0.3465, \"edcr\": 0.7234, \"format_ok\": 983, \"truncated\": 271, \"n_predictions\": 25522, \"n_documents\": 985, \"inference_time_s\": 9203.1, \"fair_tax_pp\": -0.2, \"fair_subset_size\": 982, \"fair_with_evi_ign_f1\": 0.4375, \"fair_no_evi_ign_f1\": 0.4355}, \"conclusion\": \"success\"}, \"test_eval_14b_rsft_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"f1\": 0.3849, \"ign_f1\": 0.3849, \"evi_f1\": 0.2688, \"evi_f1_tp\": 0.6025, \"edcr\": 0.7865, \"truncated\": \"67/500\", \"format_ok\": \"499/500\", \"n_docs\": 500, \"inference_time_s\": 19080, \"codalab_generated\": true}}, \"test_eval_8b_rsft_s42\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.3353, \"f1\": 0.3353, \"precision\": 0.5149, \"recall\": 0.2486, \"evi_f1_dreeam\": 0.2526, \"evi_f1_tp\": 0.6037, \"edcr\": 0.7993, \"format_ok_rate\": 0.998, \"field_compliance_rate\": 0.148, \"evidence_format_rate\": 0.148, \"n_predictions\": 14616, \"n_truncated\": 9, \"tp\": 4313, \"pred_count\": 8377, \"gold_count\": 17350}, \"conclusion\": \"success\"}, \"d145_4b_sft_s43_no_evi_2048\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4355, \"f1\": 0.4429, \"precision\": 0.4413, \"recall\": 0.4445, \"ign_precision\": 0.4205, \"ign_recall\": 0.4516, \"evi_f1\": 0, \"format_ok\": \"984/985\", \"truncated\": \"268/985\", \"n_predictions\": 32183, \"inference_time_s\": 8731.7}, \"conclusion\": \"success\"}, \"test_eval_1_7b_rsft_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"f1\": 0.2933, \"ign_f1\": 0.2933, \"precision\": 0.4625, \"recall\": 0.2148, \"evi_f1\": 0.232, \"evi_f1_tp\": 0.6196, \"edcr\": 0.8169, \"truncated\": \"369/500\", \"format_ok\": \"500/500\", \"field_compliance\": \"101/500\", \"n_predictions\": 26098, \"n_docs\": 500, \"codalab_generated\": true}}, \"test_eval_llama_rsft_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"f1\": 0.3599, \"ign_f1\": 0.3599, \"precision\": 0.479, \"recall\": 0.2882, \"evi_f1\": 0.2509, \"evi_f1_tp\": 0.5447, \"edcr\": 0.8391, \"truncated\": \"283/500\", \"format_ok\": \"500/500\", \"field_compliance\": \"176/500\", \"n_predictions\": 23330, \"n_docs\": 500, \"codalab_generated\": true}}, \"d140_1_7b_sft_s42_no_evi_2048_fix\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4233, \"fair_tax_pp\": -5.6306, \"fair_subset_size\": 971, \"fair_with_evi_ign_f1\": 0.4838, \"fair_no_evi_ign_f1\": 0.4275}, \"conclusion\": \"success\"}, \"d140_8b_sft_s42_no_evi_2048_fix\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5019, \"evidence_tax\": -0.0007, \"fair_tax_pp\": 0.042, \"fair_subset_size\": 984, \"fair_with_evi_ign_f1\": 0.5015, \"fair_no_evi_ign_f1\": 0.5019}, \"conclusion\": \"success\"}, \"eval_llama_rsft_s42_no_evi_2048\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5559, \"f1\": 0.5703, \"evi_f1_dreeam\": 0.0006, \"evi_f1_tp\": 0.0007, \"edcr\": 0.625, \"format_ok\": \"984/985\", \"truncated\": \"140/985\", \"n_predictions\": 24365, \"inference_time_s\": 15710.3, \"fair_tax_pp\": 2.1721, \"fair_subset_size\": 983, \"fair_with_evi_ign_f1\": 0.5779, \"fair_no_evi_ign_f1\": 0.5562, \"raw_tax_pp\": 2.191}, \"conclusion\": \"success\"}, \"d140_4b_sft_s42_with_evi_2048\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.3946, \"f1\": 0.4033, \"evi_f1_dreeam\": 0.3129, \"evi_f1_tp\": 0.7906, \"edcr\": 0.7262, \"format_ok\": 983, \"format_total\": 985, \"truncated\": 243, \"fair_tax_pp\": 0.726, \"fair_subset_size\": 981, \"fair_with_evi_ign_f1\": 0.3951, \"fair_no_evi_ign_f1\": 0.4024, \"raw_tax_pp\": 0.6935}}, \"d140_4b_sft_s42_no_evi_2048_fix\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4016, \"f1\": 0.4095, \"evi_f1_dreeam\": 0, \"evi_f1_tp\": 0, \"edcr\": 0, \"format_ok\": \"983/985\", \"format_ok_pct\": 99.8, \"truncated\": \"178/985\", \"n_predictions\": 25638, \"inference_time_s\": 7606.2, \"fair_tax_pp\": 0.726, \"fair_subset_size\": 981, \"fair_with_evi_ign_f1\": 0.3951, \"fair_no_evi_ign_f1\": 0.4024, \"raw_tax_pp\": 0.6935}, \"conclusion\": \"success\"}, \"test_eval_4b_rsft_s42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"eval_llama_rsft_s42_with_evidence_2048\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.5774, \"f1\": 0.5892, \"evi_f1_tp\": 0.8222, \"evi_f1_joint\": 0.4719, \"edcr\": 0.6143, \"format_ok\": \"984/985\", \"truncated\": \"90/985\", \"n_predictions\": 18129, \"fair_tax_pp\": 2.1721, \"fair_subset_size\": 983, \"fair_with_evi_ign_f1\": 0.5779, \"fair_no_evi_ign_f1\": 0.5562, \"raw_tax_pp\": 2.191}}, \"d140_8b_sft_s42_with_evi_2048\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5012, \"ign_precision\": 0.469, \"ign_recall\": 0.5382, \"f1\": 0.5219, \"evi_f1_joint\": 0.4087, \"evi_f1_tp_only\": 0.8044, \"edcr\": 0.7039, \"format_ok_rate\": 0.999, \"truncated_count\": 236, \"truncated_rate\": 0.2396, \"total_docs\": 985, \"predictions\": 25007, \"inference_time_s\": 10486}, \"conclusion\": \"success\"}, \"plan017_14b_rsft_eval_2048\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5896, \"f1\": 0.602, \"ign_precision\": 0.5766, \"ign_recall\": 0.6032, \"evi_f1_joint\": 0.4871, \"evi_f1_tp\": 0.8362, \"edcr\": 0.5496, \"format_ok_rate\": 1, \"n_truncated\": 18, \"n_documents\": 985, \"n_predictions\": 13979, \"inference_time_seconds\": 17372.9}, \"conclusion\": \"success\"}, \"d140_4b_sft_s42_no_evi_2048\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"d140_8b_sft_s42_no_evi_2048\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"d140_1_7b_sft_s42_no_evi_2048\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"ign_f1\": 0.3925, \"f1\": 0.404, \"ign_precision\": 0.4102, \"ign_recall\": 0.3763, \"format_ok_rate\": 1, \"n_truncated\": 498, \"truncated_rate\": 0.5056, \"n_predictions\": 47069, \"evi_f1\": 0, \"edcr\": 0, \"inference_time_seconds\": 7394.1}}, \"d140_1_7b_sft_s42_with_evi_2048\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4806, \"f1\": 0.4951, \"ign_precision\": 0.4759, \"ign_recall\": 0.4854, \"evi_f1_tp\": 0.8006, \"evi_f1_joint\": 0.3941, \"edcr\": 0.7175, \"format_ok\": \"985/985\", \"truncated\": \"267/985\", \"n_predictions\": 25534}, \"conclusion\": \"success\"}, \"d112_rsft_s44_generate\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"eval_llama_sft_s44_no_evidence_2048\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.4373, \"f1\": 0.4504, \"ign_precision\": 0.3947, \"ign_recall\": 0.4902, \"format_ok_rate\": 0.9919, \"n_format_ok\": 977, \"n_truncated\": 246, \"truncation_rate\": 0.2497, \"n_predictions\": 28366, \"n_documents\": 985, \"fair_tax_pp\": -4.18, \"fair_tax_pp_note\": \"INVALIDATED: used @1024 with-evi\", \"fair_subset_docs\": 977, \"fair_with_evi_ign_f1\": 0.4813, \"fair_no_evi_ign_f1\": 0.4395, \"vs_1024_ign_f1_delta\": \"+10.47pp\", \"vs_1024_truncation_delta\": \"-16.7pp\", \"matched_fair_tax_pp\": -2.8345, \"matched_fair_subset_docs\": 977, \"matched_fair_with_evi_ign_f1\": 0.4679, \"matched_fair_no_evi_ign_f1\": 0.4395}}, \"eval_llama_sft_s43_no_evidence_2048_r2\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.3389, \"f1\": 0.3575, \"format_ok\": 834, \"format_ok_rate\": 0.8467, \"truncated\": 359, \"predictions\": 23070, \"inference_time_seconds\": 14987, \"matched_fair_tax_pp\": -11.2048, \"matched_fair_subset_docs\": 834, \"matched_fair_with_evi_ign_f1\": 0.491, \"matched_fair_no_evi_ign_f1\": 0.3789}, \"conclusion\": \"success\"}, \"eval_llama_sft_s42_no_evidence_2048\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.521, \"f1\": 0.5306, \"ign_precision\": 0.5342, \"ign_recall\": 0.5085, \"format_ok_rate\": 0.8873, \"n_format_ok\": 874, \"n_truncated\": 201, \"truncation_rate\": 0.2041, \"n_predictions\": 23031, \"n_documents\": 985, \"pred_count_dedup\": 11109, \"fair_tax_pp\": 1.2, \"fair_tax_pp_note\": \"INVALIDATED: used @1024 with-evi\", \"fair_subset_docs\": 873, \"fair_with_evi_ign_f1\": 0.5443, \"fair_no_evi_ign_f1\": 0.5564, \"raw_tax_pp\": -1.74, \"vs_1024_ign_f1_delta\": \"-0.09pp\", \"vs_1024_format_ok_delta\": \"0pp (874→874)\", \"vs_1024_fair_tax_delta\": \"-0.14pp (+1.34→+1.20)\", \"matched_fair_tax_pp\": -1.5258, \"matched_fair_subset_docs\": 873, \"matched_fair_with_evi_ign_f1\": 0.5716, \"matched_fair_no_evi_ign_f1\": 0.5564}, \"conclusion\": \"success\"}, \"eval_llama_sft_s43_with_evidence_2048\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.4954, \"f1\": 0.5105, \"evi_f1\": 0.8015, \"evi_f1_joint\": 0.4001, \"edcr\": 0.6574, \"format_ok\": \"985/985\", \"truncated\": \"242/985\", \"predictions\": 24949, \"inference_time_s\": 12343.3}}, \"d112_rsft_s44_ced_score\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"total_scored\": 24216, \"selected_count\": 3014, \"selection_rate\": 0.124, \"mean_f1\": 0.676, \"mean_ced\": 0.676}}, \"eval_llama_sft_s44_with_evidence_2048\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4655, \"f1\": 0.4798, \"evi_f1_joint\": 0.3719, \"evi_f1\": 0.8393, \"edcr\": 0.7122, \"format_ok\": \"985/985\", \"truncated\": \"177/985\", \"predictions\": 21530, \"inference_time_s\": 11062}, \"conclusion\": \"success\"}, \"plan017_14b_rsft_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5886, \"f1\": 0.6009, \"ign_precision\": 0.5794, \"ign_recall\": 0.5981, \"precision\": 0.6014, \"recall\": 0.6004, \"format_ok\": 985, \"format_ok_rate\": 1, \"truncated\": 105, \"evi_f1\": 0.8392, \"evi_f1_joint\": 0.4859, \"edcr\": 0.5396, \"tp\": 7295, \"pred_count\": 12130, \"gold_count\": 12151, \"n_total\": 985, \"n_predictions\": 13275, \"inference_time_seconds\": 16337.3}, \"conclusion\": \"success\"}, \"eval_llama_sft_s42_with_evidence_2048\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5649, \"f1\": 0.5767, \"format_ok\": 976, \"format_ok_rate\": 0.9909, \"truncated\": 147, \"predictions\": 20302, \"evi_f1\": 0.803, \"edcr\": 0.6428, \"inference_time_seconds\": 10491.7}, \"conclusion\": \"success\"}, \"plan017_14b_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5432, \"f1\": 0.5536, \"ign_precision\": 0.5193, \"ign_recall\": 0.5693, \"precision\": 0.5414, \"recall\": 0.5664, \"evi_f1\": 0, \"edcr\": 0, \"format_ok\": 953, \"format_ok_rate\": 0.9675, \"n_total\": 985, \"n_predictions\": 15333, \"n_truncated\": 106, \"tp\": 6882, \"pred_count\": 12711, \"gold_count\": 12151, \"inference_time_seconds\": 9427.5}, \"conclusion\": \"success\"}, \"eval_llama_sft_s43_no_evidence_2048\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan017_14b_rsft_generate_r4\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"total_lines\": 24216, \"unique_docs\": 3027, \"generations_per_doc\": 8}}, \"eval_llama_sft_s43_no_evidence_r2\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.3391, \"format_compliance\": 0.616, \"n_truncated\": 378}, \"conclusion\": \"success\"}, \"plan017_14b_rsft_train\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 0.5005, \"mean_token_accuracy\": 0.8783, \"total_steps\": 1131, \"runtime_seconds\": 3958}, \"conclusion\": \"success\"}, \"plan017_14b_ced_scoring\": {\"status\": \"DONE\", \"metrics\": {\"total_scored\": 24216, \"unique_docs_total\": 3027, \"selected_count\": 3015, \"unique_docs_selected\": 3015, \"selection_rate\": 0.1245, \"all_mean_f1\": 0.616, \"all_mean_ced\": 0.568, \"all_mean_combined\": 0.673, \"selected_mean_f1\": 0.73, \"selected_mean_ced\": 0.69, \"selected_mean_combined\": 0.768, \"selected_median_f1\": 0.75, \"selected_median_ced\": 0.71, \"f1_filter_dropped_gens\": 497, \"f1_filter_dropped_docs\": 12, \"truncated_count\": 1701, \"truncated_ratio\": 0.07, \"truncated_mean_f1\": 0.487, \"non_truncated_mean_f1\": 0.625, \"truncation_f1_gap\": 0.139, \"format_reward_mean\": 0.9996, \"output_file\": \"/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl\", \"output_size_mb\": 9.1, \"runtime_hours\": 1}, \"conclusion\": \"success\"}, \"eval_llama_sft_s44_no_evidence\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.3326, \"f1\": 0.3348, \"format_compliance\": 0.945, \"format_ok\": 931, \"n_documents\": 985, \"n_truncated\": 411}, \"conclusion\": \"success\"}, \"eval_llama_rsft_s44_no_evidence\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.555, \"f1\": 0.5674, \"evi_f1\": 0.001, \"evi_f1_joint\": 0.0001, \"edcr\": 0.6818, \"format_compliance\": 0.999, \"n_truncated\": 178, \"n_predictions\": 18089, \"inference_time_s\": 6555.2, \"n_documents\": 985, \"n_format_ok\": 984}}, \"eval_llama_sft_s43_no_evidence\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"migration_bjb2_to_westd\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan017_14b_rsft_generate_r3\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"eval_llama_sft_s42_no_evidence_std_r2\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5219, \"f1\": 0.5311, \"ign_precision\": 0.542, \"ign_recall\": 0.5031, \"evi_f1_joint\": 0.0005, \"evi_f1_tp\": 0.0102, \"edcr\": 0.58, \"format_ok_rate\": 0.8873, \"n_truncated\": 219, \"n_predictions\": 16292, \"inference_time_seconds\": 6927.2}, \"conclusion\": \"success\"}, \"llama_sft_s44_train_eval_r3\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4802, \"rel_f1\": 0.4902, \"evi_f1_joint\": 0.3913, \"evi_f1_tp\": 0.8502, \"edcr\": 0.6579, \"format_ok\": \"985/985\", \"n_truncated\": 240, \"n_predictions\": 14990}, \"conclusion\": \"success\"}, \"d102_8b_rsft_k1_s43\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.3862, \"mean_token_accuracy\": 0.8735, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2894.88, \"data_samples\": 3018, \"ign_f1\": 0.5471, \"rel_f1\": 0.5651, \"evi_f1\": 0.818, \"edcr\": 0.6094, \"num_preds\": 16226, \"truncated\": \"231/985\", \"format_ok\": \"985/985\"}}, \"d102_8b_rsft_k1_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.3877, \"mean_token_accuracy\": 0.8579, \"epochs\": 3, \"global_steps\": 1134, \"runtime_seconds\": 2915.82, \"entropy\": 0.5847, \"data_samples\": 3018}}, \"llama_sft_s43_train_eval_r3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.5142, \"evi_f1_joint\": 0.422, \"evi_f1_tp\": 0.8245, \"edcr\": 0.5866, \"re_p_ign\": 0.4917, \"re_r_ign\": 0.5389, \"train_loss_final\": 0.521}}, \"plan017_14b_rsft_generate_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"eval_llama_sft_s42_no_evidence_std\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"llama_sft_s44_train_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"llama_sft_s43_train_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan017_14b_rsft_generate\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"llama_sft_s44_train_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"llama_sft_s43_train_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"eval_llama_rsft_s43_no_evidence\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5546, \"f1\": 0.567, \"evi_f1\": 0, \"evi_f1_tp\": 0, \"evi_f1_joint\": 0, \"edcr\": 0, \"format_compliance\": 0.998, \"n_truncated\": 183, \"n_predictions\": 18008, \"inference_time_seconds\": 7798, \"n_documents\": 985, \"n_format_ok\": 983}, \"conclusion\": \"negative\"}, \"llama_rsft_s44_pipeline\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.5587, \"f1\": 0.5706, \"evi_f1_joint\": 0.4609, \"evi_f1_tp\": 0.8328, \"edcr\": 0.5829, \"ign_precision\": 0.5574, \"ign_recall\": 0.5601, \"format_ok_rate\": 1, \"n_truncated\": 166, \"n_predictions\": 14685}}, \"plan010_nli_large_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"f1\": 0.4636, \"ign_f1\": 0.4533, \"evi_f1_joint\": 0.3606, \"evi_f1_tp\": 0.8194, \"edcr\": 0.653, \"format_compliance\": 1, \"n_truncated\": 180, \"n_predictions\": 14870, \"inference_time_s\": 10064}}, \"eval_llama_rsft_s42_no_evidence\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5526, \"f1\": 0.5666, \"evi_f1\": 0.0003, \"evi_f1_joint\": 0.0002, \"edcr\": 0.3333, \"format_compliance\": 0.998, \"n_truncated\": 190, \"n_predictions\": 18280, \"inference_time_s\": 8230}, \"conclusion\": \"negative\"}, \"plan010_nli_large_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan010_nli_large_ablation\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"eval_llama_rsft_k1_s43\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.5662, \"f1\": 0.578, \"evi_f1_joint\": 0.4644, \"evi_f1_tp\": 0.8287, \"edcr\": 0.5783, \"format_compliance\": 1, \"n_truncated\": 173, \"n_documents\": 985, \"n_predictions\": 14967, \"inference_time_s\": 8212.4}}, \"plan_021_deep_error_analysis\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_020_mechanistic_analysis\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan019_1_7b_rsft_no_evidence_eval_2048\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"ign_f1\": 0.4344, \"f1\": 0.4544, \"ign_precision\": 0.4331, \"ign_recall\": 0.4357, \"precision\": 0.462, \"recall\": 0.447, \"evi_f1\": 0, \"edcr\": 0, \"format_ok_rate\": 0.9726, \"n_predictions\": 46318, \"n_truncated\": 568, \"n_documents\": 985, \"truncation_rate\": 0.5766, \"no_evidence\": true, \"max_new_tokens\": 2048, \"evidence_tax_pp\": -7.75, \"inference_time_s\": 19023}}, \"seed_llama_rsft_k1_s43\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"d112_rsft_no_evidence_eval_r3\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5246, \"f1\": 0.5341, \"ign_precision\": 0.5122, \"ign_recall\": 0.5377, \"precision\": 0.5338, \"recall\": 0.5344, \"evi_f1\": 0, \"edcr\": 0, \"format_ok_rate\": 0.998, \"n_predictions\": 16018, \"n_truncated\": 144, \"n_documents\": 985, \"no_evidence\": true, \"evidence_tax\": 0.0094, \"inference_time_s\": 9288}, \"conclusion\": \"success\"}, \"plan019_8b_rsft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5336, \"f1\": 0.553, \"ign_precision\": 0.5061, \"ign_recall\": 0.5643, \"precision\": 0.5324, \"recall\": 0.5753, \"evi_f1_tp\": 0.0652, \"evi_f1_joint\": 0.0411, \"edcr\": 0.6207, \"format_ok_rate\": 1, \"n_predictions\": 20605, \"n_truncated\": 310, \"n_documents\": 985, \"no_evidence\": true, \"evidence_tax_vs_mean\": -0.0078}, \"conclusion\": \"success\"}, \"plan019_8b_sft_s43_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5324, \"f1\": 0.5457, \"ign_precision\": 0.5319, \"ign_recall\": 0.533, \"precision\": 0.555, \"recall\": 0.5367, \"evi_f1_tp\": 0.8333, \"evi_f1_joint\": 0.443, \"edcr\": 0.5805, \"format_ok_rate\": 1, \"n_predictions\": 13933, \"n_truncated\": 139, \"n_documents\": 985}, \"conclusion\": \"success\"}, \"d112_rsft_s44_eval_bf16\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5152, \"f1\": 0.5274, \"evi_f1_dreeam\": 0.4277, \"evi_f1_tp\": 0.8175, \"edcr\": 0.5987, \"format_compliance_rate\": 0.999, \"n_truncated\": 182, \"n_total\": 985, \"n_predictions\": 15050}, \"conclusion\": \"success\"}, \"plan019_1_7b_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4352, \"f1\": 0.4552, \"evi_f1_dreeam\": 0, \"evi_f1_tp\": 0, \"edcr\": 0, \"format_ok_rate\": 0.971, \"truncated_rate\": 0.592, \"predictions\": 25221}, \"conclusion\": \"killed\"}, \"plan019_8b_sft_s43\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.5684, \"eval_loss\": 0.719, \"eval_mean_token_accuracy\": 0.8378, \"train_runtime_s\": 6639, \"epochs\": 3, \"train_steps\": 570}}, \"plan017_14b_sft_eval_r2\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5507, \"ign_precision\": 0.5268, \"ign_recall\": 0.5768, \"f1\": 0.5611, \"precision\": 0.5481, \"recall\": 0.5748, \"format_compliance_rate\": 1, \"field_compliance_rate\": 0.8589, \"evidence_format_rate\": 0.8589, \"n_truncated\": 139, \"n_total\": 985, \"n_parseable\": 985, \"n_predictions\": 14081, \"inference_time_seconds\": 18011.3, \"evi_precision\": 0.8197, \"evi_recall\": 0.839, \"evi_f1\": 0.8292, \"evi_f1_joint\": 0.4453, \"evi_joint_precision\": 0.4174, \"evi_joint_recall\": 0.4772, \"edcr\": 0.597}, \"conclusion\": \"success\"}, \"d112_rsft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan019_8b_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"d112_rsft_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"d112_rsft_s44_train_bf16\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan017_14b_sft_no_evidence_eval_r2\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.551, \"ign_precision\": 0.5149, \"ign_recall\": 0.5926, \"f1\": 0.5649, \"precision\": 0.5386, \"recall\": 0.5939, \"format_compliance_rate\": 0.9868, \"n_truncated\": 105, \"n_predictions\": 15605, \"inference_time_seconds\": 14497.8}, \"conclusion\": \"success\"}, \"d112_rsft_s44_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\", \"metrics\": {\"ign_f1\": 0.2181, \"note\": \"INVALID: QLoRA confound — adapter trained on 4-bit quantized backbone evaluated in bf16\"}}, \"plan019_1_7b_rsft_s44_r2_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5125, \"ign_precision\": 0.5173, \"ign_recall\": 0.5078, \"f1\": 0.5294, \"precision\": 0.5434, \"recall\": 0.5162, \"evi_precision\": 0.815, \"evi_recall\": 0.8387, \"evi_f1\": 0.8267, \"edcr\": 0.6181, \"evi_joint_precision\": 0.4284, \"evi_joint_recall\": 0.4294, \"evi_f1_joint\": 0.4289, \"format_compliance_rate\": 0.999, \"field_compliance_rate\": 0.7543, \"n_truncated\": 240, \"inference_time_seconds\": 8615.6}, \"conclusion\": \"success\"}, \"d112_rsft_s44_train\": {\"status\": \"DONE\", \"conclusion\": \"failed\", \"metrics\": {\"train_loss\": 0.6488, \"global_step\": 567}}, \"plan017_14b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"plan017_14b_sft_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"plan019_1_7b_rsft_s43_r2_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5109, \"ign_precision\": 0.5186, \"ign_recall\": 0.5035, \"f1\": 0.5271, \"precision\": 0.5444, \"recall\": 0.5109, \"evi_precision\": 0.8218, \"evi_recall\": 0.834, \"evi_f1\": 0.8278, \"edcr\": 0.6245, \"evi_joint_precision\": 0.4336, \"evi_joint_recall\": 0.4221, \"evi_f1_joint\": 0.4278, \"format_compliance_rate\": 0.999, \"field_compliance_rate\": 0.7503, \"n_truncated\": 244, \"inference_time_seconds\": 8498.2}, \"conclusion\": \"success\"}, \"plan017_14b_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.5457, \"eval_loss\": 0.6292}}, \"plan019_1_7b_rsft_s44_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.5538, \"final_step\": 567, \"epoch\": 3, \"mean_token_accuracy\": 0.8706}}, \"plan019_1_7b_rsft_s43_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.5526}}, \"plan019_1_7b_rsft_s44\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan019_1_7b_rsft_s43\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan019_8b_rsft_s44_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.5451, \"f1\": 0.562, \"evi_f1_tp\": 0.8145, \"evi_f1_dreeam\": 0.4472, \"edcr\": 0.6233, \"format_ok\": \"985/985\", \"truncated\": \"230/985\", \"predictions\": 16254}}, \"d111_4b_sft_s42_reeval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.3974, \"rel_f1\": 0.4049, \"evi_f1\": 0.7986, \"evi_f1_joint\": 0.3147, \"edcr\": 0.6982}, \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard3\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard1\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard2\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"d112_rsft_s44_gen_shard0\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan019_8b_rsft_s44\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"total_steps\": 1134, \"epochs\": 3, \"samples\": 3018, \"checkpoint\": \"checkpoint-1134\", \"adapter_size_mb\": 698, \"train_loss\": 0.4725, \"mean_token_accuracy\": 0.8734}}, \"plan019_8b_sft_s44_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.4681, \"f1\": 0.4841, \"evi_f1\": 0.8361, \"evi_f1_joint\": 0.3839, \"edcr\": 0.6697, \"format_ok_rate\": 1, \"n_truncated\": 306, \"n_predictions\": 16690, \"inference_time_seconds\": 6951.1}}, \"grpo_bf16_g4_ckpt200_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.4446, \"rel_f1\": 0.4513, \"evi_f1\": 0.8053, \"evi_f1_joint\": 0.3562, \"edcr\": 0.6489, \"format_ok\": \"984/985\", \"n_truncated\": 204, \"n_predictions\": 15733, \"field_compliance_rate\": 0.792}}, \"random_rsft_k1_baseline\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 0.578, \"mean_token_accuracy\": 0.8552, \"global_steps\": 1020, \"epochs\": 3}, \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s44\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.5783, \"eval_loss\": 0.8037, \"eval_mean_token_accuracy\": 0.8238, \"global_steps\": 570, \"epochs\": 3}}, \"wave1_sft_4b_s44_eval_r2\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4734, \"f1\": 0.4838, \"ign_precision\": 0.4676, \"ign_recall\": 0.4794, \"precision\": 0.4898, \"recall\": 0.478, \"evi_f1_joint\": 0.382, \"evi_f1_tp\": 0.7875, \"edcr\": 0.6581, \"format_ok_rate\": 0.997, \"n_truncated\": 249, \"n_documents\": 985, \"n_predictions\": 16143, \"inference_time_seconds\": 6669.5}, \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s43_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4286, \"f1\": 0.4372, \"ign_precision\": 0.4475, \"ign_recall\": 0.4111, \"precision\": 0.4704, \"recall\": 0.4084, \"evi_f1\": 0.835, \"evi_f1_joint\": 0.3442, \"edcr\": 0.704, \"format_compliance\": 1, \"field_compliance\": 0.5858, \"n_total\": 985, \"n_predictions\": 18140, \"n_truncated\": 408, \"inference_time_seconds\": 5257.4}, \"conclusion\": \"success\"}, \"wave1_sft_4b_s43_eval_r2\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4365, \"rel_f1\": 0.4429, \"evi_f1_joint\": 0.3462, \"evi_f1_tp\": 0.8021, \"edcr\": 0.6827, \"format_compliance_rate\": 1, \"n_truncated\": 318, \"n_predictions\": 17055, \"inference_time_seconds\": 7157.9}, \"conclusion\": \"success\"}, \"plan019_8b_sft_s44\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 0.5691, \"eval_loss\": 0.7196, \"eval_mean_token_accuracy\": 0.8379, \"eval_entropy\": 0.5579, \"train_runtime_s\": 3823.89, \"epoch\": 3}, \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s43_r2\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 0.6881, \"eval_loss\": 0.8029, \"eval_mean_token_accuracy\": 0.8237, \"eval_entropy\": 0.681, \"epochs\": 3, \"runtime_seconds\": 2697}, \"conclusion\": \"success\"}, \"wave1_grpo_bf16_g4\": {\"status\": \"DONE\", \"metrics\": {\"reward_mean\": 1.7646, \"steps_completed\": 200, \"max_steps\": 200}, \"conclusion\": \"success\"}, \"random_rsft_k1_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4114, \"f1\": 0.4198, \"evi_f1\": 0.7964, \"evi_f1_joint\": 0.3216, \"EDCR\": 0.6971, \"format_compliance\": 0.999, \"field_compliance\": 0.7482, \"truncated\": 235, \"n_total\": 985, \"n_predictions\": 16110, \"inference_time_seconds\": 11778.5}, \"conclusion\": \"success\"}, \"grpo_bf16_g4_ckpt100_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4431, \"f1\": 0.4511, \"evi_f1\": 0.801, \"evi_f1_joint\": 0.3532, \"EDCR\": 0.6453, \"format_compliance\": 0.999, \"field_compliance\": 0.8142, \"truncated\": 182, \"n_total\": 985, \"n_predictions\": 15187, \"inference_time_seconds\": 11458.2}, \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s44_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4321, \"f1\": 0.4441, \"evi_f1_tp\": 0.819, \"evi_f1_joint\": 0.3482, \"edcr\": 0.69, \"n_truncated\": 473, \"n_predictions\": 20237, \"n_documents\": 985, \"format_ok_rate\": 1, \"field_compliance_rate\": 0.5198, \"evidence_format_rate\": 0.5198, \"inference_time_seconds\": 6146}, \"conclusion\": \"success\"}, \"plan019_1_7b_sft_s43\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"wave1_sft_4b_s44_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"wave1_sft_4b_s43_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"seed_llama_rsft_k1_s43_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"wave1_sft_4b_s44\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"wave1_sft_4b_s43\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"d102_llama_rsft_k1_s43_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"rsft_llama_k1_s43_train\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss_final\": 0.4447, \"mean_token_accuracy_final\": 0.8912, \"global_steps\": 1107, \"epochs\": 3, \"total_flos\": 386000000000000000}}, \"d102_llama_rsft_k1_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.3698, \"mean_token_accuracy\": 0.8876, \"epochs\": 3, \"global_steps\": 1107, \"runtime_seconds\": 2601.34, \"entropy\": 0.5017, \"data_samples\": 2952}}, \"d102_1_7b_rsft_k1_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.3063, \"mean_token_accuracy\": 0.8731, \"epochs\": 3, \"global_steps\": 567, \"runtime_seconds\": 899.39, \"entropy\": 0.5467, \"data_samples\": 3021}}, \"seed_comparison_prep\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"plan006_1_7b_rsft_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"rsft_s43_dev_eval_preds\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4512, \"f1\": 0.4601, \"evi_f1\": 0.8063, \"edcr\": 0.6542, \"evi_f1_joint\": 0.3605, \"format_compliance_rate\": 1, \"field_compliance_rate\": 0.809, \"n_truncated\": 184, \"inference_time_seconds\": 10982}, \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_eval_r2\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.505, \"f1\": 0.5219, \"evi_f1\": 0.8309, \"edcr\": 0.6297, \"evi_f1_joint\": 0.4223, \"format_compliance_rate\": 0.999, \"field_compliance_rate\": 0.732, \"n_truncated\": 258, \"inference_time_seconds\": 9464}, \"conclusion\": \"success\"}, \"plan_006_llama_rsft_r3_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5563, \"f1\": 0.5674, \"evi_f1\": 0.8255, \"edcr\": 0.5856, \"evi_f1_joint\": 0.4571, \"format_compliance_rate\": 0.997, \"field_compliance_rate\": 0.807, \"n_truncated\": 187, \"inference_time_seconds\": 8650}, \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_rsft_train_r2\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 0.3008, \"mean_token_accuracy\": 0.9172, \"epochs\": 3, \"runtime_seconds\": 8983}, \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_rsft_seed43_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"f1\": 0.518, \"ign_f1\": 0.5024, \"evi_f1_joint\": 0.4201, \"evi_f1_tp\": 0.8341, \"edcr\": 0.6246, \"precision\": 0.535, \"recall\": 0.5019, \"ign_precision\": 0.5099, \"ign_recall\": 0.4951, \"format_ok\": \"984/985\", \"n_truncated\": 262, \"n_predictions\": 16455}}, \"plan_006_qwen3_1_7b_rsft_test\": {\"status\": \"DONE\", \"metrics\": {\"n_predictions\": 28743, \"n_truncated\": 857, \"format_ok_rate\": 0.999, \"n_docs\": 1000, \"codalab_entries\": 27567}, \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_rsft_test\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_seed43_eval_r2\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.5727, \"ign_f1\": 0.5619, \"evi_f1\": 0.8206, \"evi_f1_joint\": 0.4551, \"edcr\": 0.6073, \"format_compliance_rate\": 1, \"n_truncated\": 197}, \"conclusion\": \"success\"}, \"plan_006_llama_rsft_test\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_seed43\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_006_llama_rsft_seed43_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"lead2_ckpt20_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4617, \"ign_f1\": 0.4533, \"evi_f1\": 0.8103, \"evi_f1_joint\": 0.3642, \"edcr\": 0.6465, \"precision\": 0.476, \"recall\": 0.4482, \"format_ok\": \"985/985\", \"truncated\": \"187/985\", \"predictions\": 14998}}, \"plan_006_qwen3_8b_rsft_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"f1\": 0.5606, \"ign_f1\": 0.5433, \"evi_f1\": 0.8052, \"evi_f1_joint\": 0.4413, \"edcr\": 0.6377, \"precision\": 0.5553, \"recall\": 0.566, \"format_ok\": \"985/985\", \"truncated\": \"267/985\", \"predictions\": 16831}}, \"plan_006_qwen3_1_7b_rsft_seed43\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"post_hoc_bm25_baseline\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"bm25_entity_k2_rel_f1\": 0.4876, \"bm25_entity_k2_evi_f1_joint\": 0.3473, \"bm25_entity_k2_edcr\": 0.7664, \"bm25_entity_k3_evi_f1_joint\": 0.2989, \"bm25_entity_k3_edcr\": 0.8256, \"bm25_oracle_k_evi_f1_joint\": 0.3834, \"bm25_oracle_k_edcr\": 0.7334, \"rsft_ced_s43_rel_f1\": 0.4601, \"rsft_ced_s43_evi_f1_joint\": 0.3605, \"rsft_ced_s43_edcr\": 0.6542, \"sft_joint_rel_f1\": 0.4049, \"sft_joint_evi_f1_joint\": 0.3147, \"sft_joint_edcr\": 0.6982, \"verdict\": \"RSFT joint generation beats BM25 post-hoc on evi_f1_joint (-1.3pp) and EDCR (-11.2pp). Even oracle-k post-hoc has 7.9pp worse EDCR than RSFT.\"}}, \"lead1_ced_evidence_filter\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"baseline_f1\": 0.4601, \"baseline_ign_f1\": 0.4512, \"baseline_evi_f1\": 0.8063, \"baseline_edcr\": 0.6542, \"tau_0.3_evi_f1\": 0.7301, \"tau_0.3_edcr\": 0.5797, \"tau_0.5_evi_f1\": 0.7297, \"tau_0.5_edcr\": 0.5784, \"tau_0.7_evi_f1\": 0.7287, \"tau_0.7_edcr\": 0.5776, \"evidence_kept_pct_tau_0.5\": 61.9, \"verdict\": \"CED filter removes ~38% evidence but drops Evi-F1 by 7.7pp and EDCR by 7.6pp\"}}, \"plan_006_qwen3_8b_rsft_train\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_rsft_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rsft_s44_dev_eval_preds\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"lead2_rsft_grpo_ced_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_016_llama_rsft_train_r3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.3724, \"mean_token_accuracy\": 0.929, \"total_steps\": 3312, \"epochs\": 3, \"runtime_seconds\": 10231}}, \"lead2_rsft_grpo_ced\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_8b_ced_scoring\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"output_samples\": 9041, \"input_candidates\": 24216, \"scoring_mode\": \"ced\", \"tau\": 0.5, \"top_k\": 3}}, \"plan_006_qwen3_1_7b_rsft_train\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.5234, \"eval_loss\": 0.8725, \"eval_mean_token_accuracy\": 0.8185, \"total_steps\": 1698, \"epochs\": 3, \"runtime_hours\": 2.25}}, \"plan_002_test_rsft_s44\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_rsft_candidates_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_016_llama_rsft_train_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_016_llama_rsft_train\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_016_llama_ced_scoring\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_ced_scoring\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"total_records\": 24216, \"selected\": 9042, \"unique_docs\": 3021, \"selection_rate\": 0.373, \"mean_f1_reward\": 0.592, \"mean_ced_reward\": 0.559, \"mean_combined_score\": 0.66, \"truncated_count\": 2920, \"truncated_mean_f1\": 0.439, \"non_truncated_mean_f1\": 0.613}}, \"plan_007_redocred_rsft_eval_r2\": {\"status\": \"DONE\", \"metrics\": {\"F1\": 0.0025, \"Ign-F1\": 0.0026, \"Evi-F1\": 0.8837, \"EDCR\": 0.9978, \"format_ok\": \"489/493\", \"truncated\": \"117/493\", \"predictions\": 8461}, \"conclusion\": \"negative\"}, \"plan_006_qwen3_1_7b_rsft_candidates\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"docs_completed\": 3027, \"total_generations\": 24216, \"lines\": 24216, \"runtime_h\": 11, \"truncation_rate\": 0.104, \"mean_diversity\": 7.4}}, \"plan_002_test_eval_s44_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_no_evidence_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.6509, \"eval_loss\": 0.8153, \"eval_mean_token_accuracy\": 0.8174, \"eval_entropy\": 0.6275, \"train_runtime_sec\": 3656, \"epoch\": 3}}, \"plan_006_qwen3_1_7b_no_evidence_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_006_qwen3_1_7b_sft_bf16\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.6884, \"eval_loss\": 0.8031, \"eval_mean_token_accuracy\": 0.8238, \"eval_entropy\": 0.682, \"train_runtime_sec\": 2473, \"train_samples_per_second\": 3.672, \"epochs\": 3, \"total_steps\": 570}}, \"plan_006_qwen3_8b_sft_bf16\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.5705, \"eval_loss\": 0.7186, \"eval_mean_token_accuracy\": 0.8377, \"eval_entropy\": 0.5614, \"train_runtime_s\": 3932, \"epoch\": 3}}, \"reeval_sft_baseline_d076\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4049, \"ign_f1\": 0.3974, \"evi_f1\": 0.7986, \"edcr\": 0.6982, \"evi_f1_joint\": 0.3147, \"format_compliance_rate\": 0.998, \"n_truncated\": 288, \"n_documents\": 985, \"n_predictions\": 16880, \"inference_time_sec\": 7056.5}}, \"plan_006_qwen3_1_7b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"f1\": 0.4945, \"ign_f1\": 0.4786, \"evi_f1\": 0.8316, \"edcr\": 0.6704, \"precision\": 0.5085, \"recall\": 0.4813, \"ign_precision\": 0.483, \"ign_recall\": 0.4743, \"evi_precision\": 0.8203, \"evi_recall\": 0.8432, \"evi_f1_joint\": 0.3958, \"format_compliance_rate\": 1, \"n_predictions\": 17184, \"n_truncated\": 314, \"inference_time_seconds\": 6848.7}}, \"plan_006_qwen3_8b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.5051, \"f1\": 0.5262, \"evi_f1\": 0.8188, \"edcr\": 0.651, \"format_ok_rate\": 0.999, \"n_truncated\": 313, \"n_predictions\": 17401, \"inference_time_s\": 7206}}, \"plan_016_llama_3_1_8b_no_evidence_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_016_llama_3_1_8b_sft\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_007_redocred_4b_sft_eval_r2\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.3659, \"f1\": 0.3706, \"evi_f1\": 0.817, \"edcr\": 0.6674, \"format_compliance_rate\": 0.996, \"n_truncated\": 139, \"n_total\": 493, \"inference_time_seconds\": 3281.7, \"precision\": 0.4316, \"recall\": 0.3247, \"ign_precision\": 0.4134, \"ign_recall\": 0.3282, \"evi_precision\": 0.8208, \"evi_recall\": 0.8131, \"n_predictions\": 8191}, \"conclusion\": \"success\"}, \"plan_006_qwen3_8b_no_evidence_eval_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_016_llama_3_1_8b_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.5452, \"rel_f1\": 0.5624, \"evi_f1\": 0, \"edcr\": 0}}, \"plan_006_qwen3_1_7b_no_evidence_eval_v3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.3982, \"rel_f1\": 0.4103, \"evi_f1\": 0, \"edcr\": 0, \"precision\": 0.4464, \"recall\": 0.3796, \"format_compliance_rate\": 1, \"n_truncated\": 501, \"inference_time_seconds\": 7465.3, \"evidence_tax\": 0.0804}}, \"plan_016_llama_3_1_8b_sft_eval\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.5384, \"rel_f1\": 0.5514, \"evi_f1\": 0.8151, \"edcr\": 0.628, \"precision\": 0.5464, \"recall\": 0.5565, \"evi_f1_joint\": 0.4317, \"format_compliance_rate\": 0.9949, \"n_truncated\": 197, \"n_predictions\": 15325, \"inference_time_seconds\": 7331.3, \"evidence_tax_ign_f1\": 0.0068, \"evidence_tax_rel_f1\": 0.011}, \"conclusion\": \"success\"}, \"plan_016_llama_grpo_qlora\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"format_reward\": 1, \"f1_reward\": 0, \"ced_reward\": 0, \"entropy\": 0.28, \"final_step\": 60, \"grad_norm\": 0, \"loss\": 0, \"frac_reward_zero_std\": 1, \"output_length_final\": 172, \"conclusion_note\": \"C2 cross-family validated: LLaMA QLoRA GRPO shows same catastrophic decoupling as Qwen (format gaming, zero IE ability)\"}}, \"plan_006_qwen3_8b_rsft_candidates\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_016_llama_rsft_candidates_r3\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_007_redocred_rsft_eval_r5\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"f1\": 0.4234, \"ign_f1\": 0.4145, \"evi_f1\": 0.8182, \"edcr\": 0.621, \"evi_joint_f1\": 0.3306, \"format_compliance\": 1, \"field_compliance\": 0.8134, \"n_documents\": 493, \"n_truncated\": 90, \"inference_time_s\": 5655.5}}, \"plan_007_redocred_rsft_eval_r4\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_002_test_rsft_s43\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_007_redocred_rsft_eval_r3\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_007_redocred_rsft_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\", \"metrics\": {\"failure_reason\": \"OOM + pipeline bug: --model_path and --sft_adapter args in wrong order. RSFT LoRA merged to bare Qwen3-4B without SFT base, causing ontology collapse. Fix: match DocRED eval param ordering.\"}}, \"plan_014_no_evidence_eval_d076\": {\"status\": \"DONE\", \"metrics\": {\"ign_f1\": 0.4721, \"f1\": 0.4876, \"precision\": 0.4901, \"recall\": 0.4851, \"format_compliance_rate\": 0.9929, \"n_truncated\": 307, \"inference_time_seconds\": 6903.9}, \"conclusion\": \"success\"}, \"plan_016_llama_rsft_candidates_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\", \"metrics\": {\"docs_completed\": 64, \"docs_total\": 3027, \"lines_generated\": 512, \"output_path\": \"/root/autodl-tmp/freige/outputs/rsft_candidates_llama_8b/generations.jsonl\", \"failure_reason\": \"Process killed externally (no traceback/error in log). Likely OOM on cuda:1. Completed 64/3027 docs (2.1%) in ~23min before termination.\"}}, \"plan_016_llama_rsft_candidates\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_007_redocred_4b_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_no_evidence_eval_v2r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_no_evidence_eval_v2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_006_qwen3_1_7b_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\", \"metrics\": {\"f1\": 0.3884, \"ign_f1\": 0.3786, \"evi_f1\": 0.0007, \"edcr\": 0.9848, \"precision\": 0.4282, \"recall\": 0.3553, \"pred_count\": 27049, \"n_truncated\": 531, \"format_ok_rate\": 0.999}}, \"plan_006_qwen3_8b_no_evidence_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"reeval_flat_nli_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.4448, \"rel_f1\": 0.4535, \"evi_f1\": 0.8039, \"evi_f1_joint\": 0.3558, \"edcr\": 0.6458, \"format_compliance_rate\": 1, \"field_compliance_rate\": 0.7787, \"n_truncated\": 205, \"inference_time_seconds\": 13253.1}}, \"reeval_ced_s44\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.4511, \"rel_f1\": 0.4621, \"evi_f1\": 0.805, \"evi_f1_joint\": 0.3677, \"edcr\": 0.635, \"format_compliance_rate\": 1, \"field_compliance_rate\": 0.802, \"n_truncated\": 190, \"inference_time_seconds\": 13077.6}}, \"reeval_ced_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ign_f1\": 0.4423, \"rel_f1\": 0.4517, \"evi_f1\": 0.8175, \"evi_f1_joint\": 0.3518, \"edcr\": 0.6569, \"format_compliance_rate\": 1, \"field_compliance_rate\": 0.7756, \"n_truncated\": 214, \"inference_time_seconds\": 10815.5}}, \"reeval_flat_nli_s44\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"plan_006_qwen3_1_7b_sft\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"reeval_flat_nli_s43_r2\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4586, \"rel_precision\": 0.4732, \"rel_recall\": 0.4449, \"ign_f1\": 0.4503, \"evi_f1\": 0.8113, \"evi_precision\": 0.8035, \"evi_recall\": 0.8192, \"evi_f1_joint\": 0.358, \"edcr\": 0.6552, \"format_ok_rate\": 0.999, \"n_truncated\": 184, \"n_predictions\": 15015}, \"conclusion\": \"success\"}, \"eval_rsft_ced_s45\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4514, \"ign_f1\": 0.4416, \"evi_f1\": 0.8174, \"rel_p\": 0.4718, \"rel_r\": 0.4326, \"edcr\": 0.655, \"evi_f1_joint\": 0.3558, \"n_truncated\": 206, \"format_ok_rate\": 1}}, \"eval_rsft_ced_s43\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4601, \"ign_f1\": 0.4512, \"precision\": 0.4696, \"recall\": 0.4509, \"evi_f1\": 0.8063, \"evi_precision\": 0.8025, \"evi_recall\": 0.8101, \"edcr\": 0.6542, \"evi_f1_joint\": 0.3605, \"format_ok_rate\": 1, \"n_truncated\": 184, \"n_predictions\": 15051, \"inference_time_seconds\": 10768.2}, \"conclusion\": \"success\"}, \"eval_plan_014_no_evidence_r2\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4876, \"ign_f1\": 0.4721, \"evi_f1\": 0, \"edcr\": 0, \"evi_f1_joint\": 0, \"precision\": 0.4901, \"recall\": 0.4851, \"ign_precision\": 0.4654, \"ign_recall\": 0.4791, \"format_compliance\": 0.993, \"truncation_rate\": 0.312, \"n_predictions\": 21181, \"n_documents\": 985}, \"conclusion\": \"success\"}, \"mvp2_ced_reranker_poc\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ced_reranker_rel_f1\": 0.486367, \"ced_reranker_ign_f1\": 0.473634, \"ced_reranker_evi_f1\": 0.8188, \"oracle_rel_f1\": 0.623746, \"oracle_ign_f1\": 0.612518, \"random_rel_f1\": 0.453783, \"random_ign_f1\": 0.439677}}, \"eval_flat_nli_seed45\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.455052, \"ign_f1\": 0.446181, \"evi_f1\": 0.815399, \"edcr\": 0.652133, \"evi_f1_joint\": 0.355612}, \"conclusion\": \"success\"}, \"eval_flat_nli_s44\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.461506, \"ign_f1\": 0.452126, \"evi_f1\": 0.813123, \"edcr\": 0.645808, \"evi_f1_joint\": 0.359673}}, \"rsft_ced_s45_train_r4\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"training_completed\": true, \"checkpoint\": \"checkpoint-510\", \"note\": \"Training metrics not captured (r4 retry after OOM). Eval running as eval_rsft_ced_s45.\"}}, \"rsft_ced_s43_train_r3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.6151, \"eval_loss\": 0.7618, \"task_eval_f1\": 0.5026, \"task_eval_ign_f1\": 0.4932, \"task_eval_evi_f1\": 0.7624, \"task_eval_edcr\": 0.6516, \"total_steps\": 510, \"epochs\": 3, \"training_hours\": 1.82}}, \"eval_plan_014_no_evidence\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rsft_ced_s45_train_r3\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rsft_ced_s45_train_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"rsft_ced_s43_train_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"reeval_rsft_topk3\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4454, \"rel_precision\": 0.4512, \"rel_recall\": 0.4398, \"ign_f1\": 0.4364, \"evi_f1\": 0.8088, \"edcr\": 0.6635, \"format_ok_rate\": 0.999, \"n_truncated\": 214, \"n_predictions\": 16020, \"inference_time_seconds\": 3546.4, \"ign_f1_corrected\": true}, \"conclusion\": \"negative\"}, \"rsft_ced_s43_train\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"rsft_ced_s45_train\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"reeval_flat_nli_s43\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4523, \"ign_f1\": 0.4523, \"evi_f1\": 0.8158, \"edcr\": 0.6505, \"num_preds\": 15357, \"format_ok\": \"984/985\", \"truncated\": \"211/985\", \"inference_time_s\": 3515.8}, \"conclusion\": \"success\"}, \"plan_003_edcr_diagnostic\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"methods_evaluated\": 15, \"edcr_vs_rel_f1_spearman\": -0.9648, \"edcr_vs_rel_f1_pvalue\": 0.0001, \"edcr_vs_evi_f1_spearman\": 0.0022, \"edcr_vs_evi_f1_pvalue\": 0.9941, \"edcr_range\": \"0.63-0.99\", \"unique_diagnostic_value\": \"identifies pathological models (GRPO QLoRA) with high evi_f1 but catastrophically low rel_f1\"}}, \"eval_flat_nli_seed44\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"eval_plan_012_dpo_1ep_fixed_r2\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.4034, \"evi_f1\": 0.8088, \"edcr\": 0.7139, \"format_ok_rate\": 0.999, \"truncated_rate\": 0.343, \"predictions\": 19107, \"ign_f1\": 0.4034, \"precision\": 0.3809, \"recall\": 0.4287, \"vs_sft_delta\": -0.0023, \"note\": \"DPO 1ep matches SFT baseline. 1ep→3ep trajectory shows gradual decoupling (rel_f1↓ evi_f1↑), consistent with GRPO pattern. Ign-F1=F1 exact match needs investigation.\"}}, \"plan_001_flat_nli_seed44\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.6247, \"eval_loss\": 0.7564, \"eval_mean_token_accuracy\": 0.8299, \"task_eval_f1_ep1\": 0.4306, \"task_eval_f1_ep2\": 0.4884, \"task_eval_f1_ep3\": 0.4897, \"task_eval_evi_f1_ep3\": 0.78, \"task_eval_edcr_ep3\": 0.6596, \"task_eval_ign_f1_ep3\": 0.4897, \"train_runtime_sec\": 6197, \"num_epochs\": 3, \"total_steps\": 507}}, \"plan_009_dynamics_figure\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"plan_001_flat_nli_seed45\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"task_eval_rel_f1\": 0.4876, \"task_eval_evi_f1\": 0.7927, \"task_eval_edcr\": 0.6517, \"train_loss\": 0.6245, \"runtime_hours\": 1.69, \"note\": \"task-eval on 50 docs only, full dev eval needed\"}}, \"plan_011_bf16_g8_step_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"step_30\": {\"rel_f1\": 0.434, \"evi_f1\": 0.8063, \"edcr\": 0.6807}, \"step_50\": {\"rel_f1\": 0.4276, \"evi_f1\": 0.8024, \"edcr\": 0.6855}, \"step_70\": {\"rel_f1\": 0.4341, \"evi_f1\": 0.8099, \"edcr\": 0.6685}, \"best_step\": \"step_70\", \"trend\": \"non-monotonic, all < ckpt-100 (0.4549)\"}}, \"plan_011_eval_g8_bf16_ckpt100\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_eval_rsft_s44\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"eval_plan_008_topk3_fixed\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"eval_plan_012_dpo_1ep_fixed\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"eval_plan_008_rsft_topk3\": {\"status\": \"DONE\", \"conclusion\": \"killed\", \"metrics\": {\"note\": \"INVALID — missing --sft_adapter, killed by Director instruction\"}}, \"plan_012_dpo_ced\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.3429, \"evi_f1\": 0.8403, \"edcr\": 0.7294, \"format_ok_rate\": 0.995, \"checkpoint\": \"checkpoint-501\", \"rewards_accuracy\": 1, \"margins\": 9.01}}, \"plan_012_dpo_ced_1ep\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.0022, \"evi_f1\": 0.75, \"edcr\": 0.9982, \"format_ok\": \"981/985\", \"truncated\": \"358/985\", \"tp\": 34, \"n_preds\": 19265, \"inference_time_s\": 3643, \"train_loss_final\": 0.59, \"rewards_accuracy\": 0.82, \"rewards_margins\": 0.86, \"total_steps\": 167, \"training_time_min\": 33}, \"conclusion\": \"negative\"}, \"eval_plan_001_flat_nli_s43\": {\"status\": \"DONE\", \"conclusion\": \"failed\", \"metrics\": {\"rel_f1\": 0.0022, \"ign_f1\": 0.0022, \"evi_f1\": 0.8533, \"edcr\": 0.9982, \"num_preds\": 17285, \"format_ok\": \"981/985\", \"truncated\": \"251/985\", \"tp\": 32, \"note\": \"INVALID — missing --sft_adapter, same bug as DPO 1ep eval\"}}, \"eval_plan_012_dpo_ced_1ep\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.0022, \"ign_f1\": 0.0022, \"evi_f1\": 0.75, \"edcr\": 0.9982, \"num_preds\": 19265, \"format_ok\": \"981/985\", \"truncated\": \"358/985\", \"tp\": 34, \"inference_time_s\": 3643}}, \"plan_008_rsft_topk3\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 0.5543, \"eval_loss\": 0.8297, \"eval_mean_token_accuracy\": 0.8228, \"eval_entropy\": 0.6001, \"train_runtime_sec\": 10916, \"total_steps\": 1509, \"epochs\": 3, \"trainable_params_pct\": 3.18, \"rsft_samples\": 8037, \"ced_score_mean\": 0.621, \"task_eval_f1_ep1\": 0.4848, \"task_eval_f1_ep2\": 0.4824, \"task_eval_f1_ep3\": 0.5012, \"task_eval_evi_f1_ep1\": 0.745, \"task_eval_evi_f1_ep2\": 0.6997, \"task_eval_evi_f1_ep3\": 0.6816, \"task_eval_edcr_ep1\": 0.6525, \"task_eval_edcr_ep2\": 0.6529, \"task_eval_edcr_ep3\": 0.5963, \"task_eval_note\": \"50-doc subset, not full dev\"}, \"conclusion\": \"success\"}, \"plan_001_flat_nli_seed43\": {\"status\": \"DONE\", \"metrics\": {\"train_loss_final\": 0.6257, \"train_loss_min\": 0.5895, \"eval_loss_epoch3\": 0.7567, \"eval_accuracy_epoch3\": 0.8298, \"total_steps\": 507, \"epochs\": 3, \"train_runtime_seconds\": 6880, \"task_eval_f1_ep1\": 0.4825, \"task_eval_f1_ep2\": 0.4542, \"task_eval_f1_ep3\": 0.4866, \"task_eval_evi_f1_ep3\": 0.7834, \"task_eval_edcr_ep3\": 0.6402, \"task_eval_note\": \"50-doc subset, not full dev\"}, \"conclusion\": \"success\"}, \"plan_009_flatnli_reward_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_009_extract_reward_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"eval_sft_baseline_noquant\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4106, \"rel_precision\": 0.4198, \"rel_recall\": 0.4019, \"evi_f1\": 0.8013, \"evi_precision\": 0.8005, \"evi_recall\": 0.8022, \"evi_f1_joint\": 0.3216, \"edcr\": 0.7039, \"format_ok_rate\": 0.998, \"field_compliance_rate\": 0.7066, \"n_predictions\": 16774, \"n_truncated\": 288, \"n_documents\": 985, \"inference_time_seconds\": 3677.9}, \"conclusion\": \"success\"}, \"plan_009_flatnli_reward_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"eval_plan_012_dpo_ced_ckpt400\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_009_forgetting_figure\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"eval_plan_014_sft_no_evidence\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4893, \"rel_ign_f1\": 0.4893, \"rel_precision\": 0.4884, \"rel_recall\": 0.4902, \"evi_f1\": 0, \"evi_precision\": 0, \"evi_recall\": 0, \"edcr\": 0, \"format_ok_rate\": 0.9919, \"n_truncated\": 298, \"n_predictions\": 21064, \"n_documents\": 985, \"n_parseable\": 977, \"inference_time_seconds\": 4103.8}, \"conclusion\": \"success\"}, \"plan_014_sft_no_evidence\": {\"status\": \"DONE\", \"metrics\": {\"train_loss\": 0.7077, \"eval_loss\": 0.8781, \"eval_token_accuracy\": 0.8086, \"epochs\": 3, \"total_steps\": 570, \"train_runtime_min\": 64, \"samples\": 3027, \"trainable_params\": \"132M/4.15B (3.18%)\"}, \"conclusion\": \"success\"}, \"plan_002_test_eval_s44\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"plan_001_rsft_flat_nli\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.6238, \"train_loss_min\": 0.5803, \"mean_token_accuracy\": 0.8528, \"train_runtime_sec\": 2946, \"epochs\": 3, \"total_steps\": 507, \"samples\": 2691}}, \"eval_plan_001_flat_nli\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4539, \"ign_f1\": 0.4539, \"evi_f1\": 0.8043, \"edcr\": 0.6431, \"precision\": 0.4671, \"recall\": 0.4414, \"evi_precision\": 0.8143, \"evi_recall\": 0.7945, \"format_ok_rate\": 1, \"n_truncated\": 199, \"n_documents\": 985, \"n_predictions\": 15294, \"inference_time_seconds\": 3631}, \"conclusion\": \"success\"}, \"eval_grpo_g8_bf16\": {\"status\": \"DONE\", \"metrics\": {\"ckpt80_rel_f1\": 0.4456, \"ckpt80_ign_f1\": 0.4456, \"ckpt80_evi_f1\": 0.8034, \"ckpt80_edcr\": 0.6409, \"ckpt80_format_ok\": \"984/985\", \"ckpt80_truncated\": 50, \"ckpt90_rel_f1\": 0.4523, \"ckpt90_ign_f1\": 0.4523, \"ckpt90_evi_f1\": 0.8052, \"ckpt90_edcr\": 0.6414, \"ckpt90_format_ok\": \"983/985\", \"ckpt90_truncated\": 61, \"ckpt100_rel_f1\": 0.4549, \"ckpt100_ign_f1\": 0.4549, \"ckpt100_evi_f1\": 0.8086, \"ckpt100_edcr\": 0.6318, \"ckpt100_format_ok\": \"985/985\", \"ckpt100_truncated\": 61, \"best_checkpoint\": \"ckpt-100\"}, \"conclusion\": \"success\"}, \"plan_015_grpo_g4_bf16_v3\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"plan_015_grpo_g4_bf16_v2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"plan_015_grpo_g4_bf16\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"plan_011_grpo_g8_bf16\": {\"status\": \"DONE\", \"metrics\": {\"final_step\": 100, \"train_runtime_s\": 554, \"reward_final\": 1.795, \"f1_reward_final\": 1.002, \"ced_reward_final\": 0.494, \"format_reward_final\": 0.3, \"frac_zero_std_final\": 0, \"kl_final\": 0.022, \"best_reward_step\": 85, \"best_reward\": 2.858, \"best_f1_reward\": 1.85, \"mode_collapse\": false, \"lora_config\": \"r=64, alpha=128, dropout=0.05, bf16\", \"checkpoints\": \"10 checkpoints (step 10-100)\"}, \"conclusion\": \"success\"}, \"plan_011_grpo_g8_bf16_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4549, \"ign_f1\": 0.4549, \"evi_f1\": 0.8086, \"edcr\": 0.6318, \"format_ok_rate\": 1, \"n_truncated\": 61, \"n_total\": 985, \"n_predictions\": 10701, \"checkpoint\": \"checkpoint-100\", \"model\": \"Qwen3-4B + SFT merged + GRPO bf16 LoRA ckpt-100\", \"inference_time_s\": 3170.3}}, \"plan_004_dreeam_baseline\": {\"status\": \"DONE\", \"metrics\": {\"dev_rel_f1\": 63.57, \"dev_rel_ign_f1\": 61.72, \"dev_evi_f1\": 54.01, \"dev_rel_p\": 66.95, \"dev_rel_r\": 60.51, \"dev_evi_p\": 60.53, \"dev_evi_r\": 48.76}, \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r2b_maxtok1536_r2\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4504, \"ign_f1\": 0.4504, \"evi_f1\": 0.8102, \"edcr\": 0.674, \"precision\": 0.4488, \"recall\": 0.4519, \"evi_precision\": 0.8162, \"evi_recall\": 0.8044, \"n_truncated\": 146, \"n_total\": 985, \"n_predictions\": 17188, \"n_distractor_citations\": 19589, \"n_total_citations\": 29063, \"format_ok_rate\": 0.998}, \"conclusion\": \"negative\"}, \"plan_001_flat_nli_scoring\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"total_scored\": 21728, \"selected_samples\": 2691, \"selection_rate\": 0.124, \"selection_strategy\": \"top_k=1\", \"f1_threshold\": 0.1, \"output_path\": \"/root/autodl-tmp/rsft_filtered_flat_nli/rsft_train.jsonl\"}}, \"mvp2_eval_rsft_s43_r2\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4683, \"ign_f1\": 0.4683, \"evi_f1\": 0.8156, \"evi_f1_joint\": 0.3711, \"evi_f1_joint_P\": 0.3747, \"evi_f1_joint_R\": 0.3675, \"edcr\": 0.6388, \"precision\": 0.4817, \"recall\": 0.4556, \"evi_precision\": 0.8142, \"evi_recall\": 0.817, \"n_predictions\": 14970, \"n_truncated\": 171, \"format_ok_rate\": 1, \"inference_time_s\": 6316.7, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"delta_rel_f1\": 0.0626, \"delta_evi_f1\": 0.0177, \"delta_evi_f1_joint\": 0.0594, \"mvp2_pass\": true}, \"conclusion\": \"success\"}, \"mvp2_rsft_ced_scoring_topk3_r2\": {\"status\": \"DONE\", \"metrics\": {\"input_generations\": 21728, \"selected_samples\": 8037, \"unique_docs\": 2691, \"selection_rate\": 0.37, \"mean_f1\": 0.5761, \"mean_ced\": 0.6205, \"mean_combined\": 0.6787, \"f1_range_p25\": 0.444, \"f1_range_p75\": 0.717, \"ced_range_p25\": 0.487, \"ced_range_p75\": 0.774, \"truncated_samples\": 1924, \"truncated_pct\": 8.9, \"selection_strategy\": \"top_k=3\", \"f1_threshold\": 0.1, \"topk1_samples\": 2718, \"data_multiplier\": 2.96}, \"conclusion\": \"success\"}, \"mvp2_rsft_train_r1_s44\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4655, \"evi_f1\": 0.8087, \"evi_f1_joint\": 0.3713, \"evi_f1_joint_P\": 0.3775, \"evi_f1_joint_R\": 0.3653, \"edcr\": 0.635, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"delta_rel_f1\": 0.0598, \"delta_evi_f1\": 0.0108, \"delta_evi_f1_joint\": 0.0596, \"mvp2_pass\": true}, \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r2b\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4493, \"ign_f1\": 0.4493, \"evi_f1\": 0.8128, \"evi_f1_joint\": 0.349, \"evi_f1_joint_P\": 0.3455, \"evi_f1_joint_R\": 0.3526, \"edcr\": 0.6609, \"precision\": 0.4566, \"recall\": 0.4424, \"evi_precision\": 0.8201, \"evi_recall\": 0.8056, \"pred_count\": 14829, \"format_ok\": \"983/985\", \"truncated\": 179, \"inference_time_s\": 5862, \"delta_evi_f1_joint\": 0.0373}, \"conclusion\": \"success\"}, \"mvp2_eval_rsft_r2a\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4494, \"ign_f1\": 0.4494, \"evi_f1\": 0.8108, \"evi_f1_joint\": 0.3509, \"evi_f1_joint_P\": 0.3423, \"evi_f1_joint_R\": 0.3599, \"edcr\": 0.6641, \"precision\": 0.4512, \"recall\": 0.4475, \"evi_precision\": 0.8143, \"evi_recall\": 0.8073, \"format_ok_rate\": 1, \"n_predictions\": 15482, \"n_truncated\": 208, \"inference_time_s\": 5967.2, \"delta_evi_f1_joint\": 0.0392}}, \"mvp2_eval_rsft_r1\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.4449, \"evi_f1\": 0.8187, \"evi_f1_joint\": 0.3468, \"evi_f1_joint_P\": 0.3515, \"evi_f1_joint_R\": 0.3423, \"edcr\": 0.6565, \"num_preds\": 15307, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"delta_rel_f1\": 0.0392, \"delta_evi_f1\": 0.0208, \"delta_evi_f1_joint\": 0.0351, \"mvp2_pass\": true}, \"conclusion\": \"success\"}, \"mvp2_eval_sft_baseline\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4057, \"evi_f1\": 0.7979, \"evi_f1_joint\": 0.3117, \"evi_f1_joint_P\": 0.3037, \"evi_f1_joint_R\": 0.32, \"edcr\": 0.7118, \"pred_count\": 12234, \"gold_count\": 12151, \"format_ok_rate\": 0.998, \"format_compliance_rate\": 0.998, \"field_compliance_rate\": 0.6264, \"n_truncated\": 367, \"inference_time_seconds\": 6138.5}}, \"mvp2_eval_rsft_r2b_maxtok1536\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_rsft_ced_scoring_topk3\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_rsft_r2b\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4493, \"evi_f1\": 0.8128, \"edcr\": 0.6609, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"delta_rel_f1\": 0.0436, \"delta_evi_f1\": 0.0149, \"mvp2_pass\": true}}, \"mvp2_rsft_r2a\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4494, \"evi_f1\": 0.8108, \"edcr\": 0.6641, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"delta_rel_f1\": 0.0437, \"delta_evi_f1\": 0.0129, \"mvp2_pass\": true}}, \"mvp2_rsft_diagnosis\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"root_cause\": \"overfitting_plus_sft_knowledge_overwrite\", \"truncated_json_samples\": 170, \"truncated_pct\": 6.3, \"epoch1_eval_loss\": 0.756, \"epoch2_eval_loss\": 0.759, \"lora_scaling\": 2, \"rsft_zero_relation_samples\": 170, \"sft_zero_relation_docs\": 26, \"rsft_mean_relations\": 11.2, \"sft_mean_relations\": 12.5}}, \"mvp2_eval_ced_kl001_r4_last\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_kl001_r3\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_kl001_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_rsft_train_r2_fix\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_rsft_train_r1_s43\": {\"status\": \"DONE\", \"metrics\": {\"eval_loss\": 0.7622, \"train_loss\": 0.6148, \"eval_entropy\": 0.6724, \"mean_token_accuracy\": 0.8291, \"total_steps\": 510, \"epochs\": 3, \"training_hours\": 1.99}, \"conclusion\": \"success\"}, \"mvp2_eval_rsft_s43\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp2_rsft_train_r1\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.0483, \"num_preds\": 848, \"sft_baseline_rel_f1\": 0.4057, \"failure_mode\": \"relation_ontology_collapse_to_freetext\", \"epoch1_eval_loss\": 0.756, \"epoch2_eval_loss\": 0.759}}, \"mvp2_rsft_ced_scoring\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"input_generations\": 21952, \"selected_samples\": 2718, \"unique_docs\": 2691, \"selection_rate\": 0.124, \"mean_f1\": 0.6157, \"mean_ced\": 0.6683, \"f1_range\": [0.1026, 1], \"zero_f1_samples\": 0, \"selection_strategy\": \"top_k=1\", \"f1_threshold\": 0.1}}, \"mvp2_rsft_gen_s0\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_rsft_gen_s3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"generation_count\": 5288, \"unique_docs\": 659, \"format_compliance\": 0.998, \"diversity_range\": \"7.5-7.8/8\", \"exit_code\": 0}}, \"mvp2_rsft_gen_s2\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_rsft_gen_s1\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_rsft_generate\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp2_diversity_probe\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"unique_triples_t07\": 5, \"unique_triples_t10\": 8, \"jaccard_t07\": 0.17, \"jaccard_t10\": 0.051, \"format_ok_rate_t07\": 0.5, \"format_ok_rate_t10\": 0.438, \"n_samples\": 3, \"n_generations\": 8, \"note\": \"unique_triples_t07 corrected from 7 to 5.0 (mean). Reviewer: format_ok ~34% after fix, 'diversity' was JSON key name variants not semantic diversity\"}}, \"mvp2_eval_lr5e6_r1_ckpt100\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.0138, \"rel_precision\": 0.0132, \"rel_recall\": 0.0144, \"ign_f1\": 0.0138, \"evi_f1\": 0.8504, \"evi_precision\": 0.9256, \"evi_recall\": 0.7866, \"edcr\": 0.9876, \"format_ok_rate\": 0.999, \"field_compliance_rate\": 0.8162, \"evidence_format_rate\": 0.8162, \"tp\": 175, \"pred_count\": 13300, \"gold_count\": 12151, \"n_predictions\": 15498, \"n_truncated\": 181, \"n_documents\": 985, \"n_parseable\": 984, \"inference_time_seconds\": 5901.7}, \"conclusion\": \"negative\"}, \"mvp2_grpo_ced_lr5e6_r1\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_eval_lr5e6_r1_ckpt80\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.0116, \"ign_f1\": 0.0116, \"precision\": 0.0109, \"recall\": 0.0124, \"evi_f1\": 0.828, \"evi_precision\": 0.928, \"evi_recall\": 0.748, \"edcr\": 0.993, \"format_ok_rate\": 0.999, \"field_compliance_rate\": 0.788, \"pred_count\": 13828, \"gold_count\": 12151, \"n_truncated\": 210, \"inference_time_seconds\": 6099}}, \"mvp2_eval_lr5e6_r1_ckpt60_r2\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.0093, \"precision\": 0.0085, \"recall\": 0.0103, \"evi_f1\": 0.81, \"edcr\": 0.993, \"format_ok_rate\": 0.998, \"pred_count\": 14626, \"gold_count\": 12151, \"tp\": 125, \"inference_time_seconds\": 6152}}, \"mvp2_eval_lr5e6_r1_ckpt60\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp2_eval_lr5e6_r1_ckpt40_r2\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.0071, \"precision\": 0.0066, \"recall\": 0.0078, \"evi_f1\": 0.7584, \"evi_precision\": 0.9113, \"evi_recall\": 0.6494, \"edcr\": 0.9942, \"format_ok_rate\": 0.9939, \"field_compliance_rate\": 0.5675, \"pred_count\": 14434, \"gold_count\": 12151, \"tp\": 95, \"n_truncated\": 424, \"inference_time_seconds\": 6152}}, \"mvp2_eval_lr5e6_r1_ckpt20\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.0077, \"rel_precision\": 0.0071, \"rel_recall\": 0.0084, \"evi_f1\": 0.628, \"evi_precision\": 0.855, \"evi_recall\": 0.496, \"edcr\": 0.993, \"format_ok_rate\": 0.991, \"field_compliance_rate\": 0.399, \"pred_count\": 14440, \"gold_count\": 12151, \"tp\": 102, \"n_truncated\": 587, \"inference_time_seconds\": 6370.4}}, \"mvp2_eval_lr5e6_rp_r2_ckpt20\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_eval_lr5e6_r1_ckpt40\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_lr5e6_rp_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_eval_ced_kl001_r4_multi\": {\"status\": \"DONE\", \"conclusion\": \"killed\", \"metrics\": {\"checkpoint-10\": {\"f1\": 0.003, \"ign_f1\": 0.003, \"evi_f1\": 0.72, \"edcr\": 0.9983, \"format_ok_rate\": 0.999}, \"checkpoint-20\": {\"f1\": 0.0088, \"ign_f1\": 0.0088, \"evi_f1\": 0.423, \"edcr\": 0.9954, \"format_ok_rate\": 0.999}, \"checkpoint-30\": {\"f1\": 0.0338, \"ign_f1\": 0.0338, \"evi_f1\": 0.5889, \"edcr\": 0.9798, \"format_ok_rate\": 1}, \"checkpoint-50\": {\"f1\": 0.1563, \"ign_f1\": 0.1563, \"evi_f1\": 0.5643, \"edcr\": 0.8858, \"format_ok_rate\": 0.999}, \"checkpoint-60\": {\"f1\": 0.1467, \"ign_f1\": 0.1467, \"evi_f1\": 0.5763, \"edcr\": 0.9062, \"format_ok_rate\": 1}, \"checkpoint-90\": {\"f1\": 0.2108, \"ign_f1\": 0.2108, \"evi_f1\": 0.5666, \"edcr\": 0.8584, \"format_ok_rate\": 1}}}, \"mvp2_grpo_ced_lr5e6_rp_r1\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_lr5e6_p1_r1\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_eval_ced_kl001_r4_step90\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.2108, \"ign_f1\": 0.2108, \"evi_f1\": 0.5666, \"edcr\": 0.8584, \"pred_count\": 11160, \"n_truncated\": 22, \"format_ok_rate\": 1, \"n_documents\": 985}, \"conclusion\": \"negative\"}, \"mvp2_eval_ced_kl001_r4_ckpt7080\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp2_eval_ced_kl001_r4_high\": {\"status\": \"DONE\", \"conclusion\": \"failed\", \"metrics\": {\"checkpoint_60\": {\"rel_f1\": 0.1467, \"ign_f1\": 0.1467, \"precision\": 0.1909, \"recall\": 0.1192, \"evi_f1\": 0.5763, \"edcr\": 0.9062, \"pred_count\": 10041, \"gold_count\": 12151, \"n_truncated\": 16, \"format_ok_rate\": 1}, \"note\": \"Only ckpt-60 completed. Process died during ckpt-70 inference at 8% (5/62 batch). ckpt-80/90 never started.\"}}, \"mvp2_eval_ced_kl001_r4_step100\": {\"status\": \"DONE\", \"metrics\": {\"rel_f1\": 0.2167, \"ign_f1\": 0.2167, \"precision\": 0.2849, \"recall\": 0.1749, \"evi_f1\": 0.5746, \"evi_precision\": 0.5244, \"evi_recall\": 0.6353, \"edcr\": 0.8539, \"pred_count\": 7460, \"gold_count\": 12151, \"tp\": 2125, \"n_truncated\": 21, \"format_ok_rate\": 1}, \"conclusion\": \"negative\"}, \"mvp2_eval_ced_kl001_r4_ckpt90\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_eval_ced_kl001_r4_ckpt10\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.00296, \"rel_precision\": 0.00314, \"rel_recall\": 0.0028, \"evi_f1\": 0.72, \"evi_precision\": 0.6429, \"evi_recall\": 0.8182, \"edcr\": 0.9983, \"n_parseable\": 984, \"n_truncated\": 24, \"n_predictions\": 11621, \"tp\": 34, \"pred_count\": 10839, \"gold_count\": 12151, \"inference_time_seconds\": 5211.4}}, \"mvp2_eval_ced_kl001_r4_early\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"f1\": 0.1563, \"ign_f1\": 0.1563, \"evi_f1\": 0.5643, \"edcr\": 0.8858, \"precision\": 0.2356, \"recall\": 0.1169, \"evi_precision\": 0.4864, \"evi_recall\": 0.6721, \"format_ok_rate\": 0.999, \"n_parseable\": 984, \"n_truncated\": 11, \"n_predictions\": 9250, \"tp\": 1421, \"pred_count\": 6032, \"gold_count\": 12151}}, \"mvp2_grpo_flatnli_r6\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"steps_completed\": 25, \"final_frac_zero_std\": 0.9, \"final_f1_reward\": 0, \"final_flat_nli_reward\": 0, \"final_format_reward\": 0.293, \"collapse_step\": 25}}, \"mvp2_grpo_ced_kl001_r4\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_step\": 100, \"train_runtime_s\": 9069.88, \"reward_final\": 1.195, \"f1_reward_final\": 0.573, \"ced_reward_final\": 0.328, \"format_reward_final\": 0.293, \"frac_zero_std_final\": 0.2, \"kl_final\": 0.118, \"loss_final\": -0.009, \"grad_norm_final\": 0.14, \"entropy_final\": 0.067, \"completion_length_mean_final\": 520.8, \"best_reward_step\": 90, \"best_reward\": 1.37, \"best_f1_reward\": 0.72, \"best_ced_reward\": 0.353}}, \"mvp2_grpo_extract_r4\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_flatnli_r5\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_sft_eval_r3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4057, \"ign_f1\": 0.4057, \"evi_f1\": 0.7979, \"edcr\": 0.7118, \"precision\": 0.4043, \"recall\": 0.407, \"evi_precision\": 0.8035, \"evi_recall\": 0.7924, \"format_ok_rate\": 0.998, \"format_compliance_rate\": 0.626, \"n_parseable\": 617, \"n_truncated\": 367, \"n_predictions\": 18815}}, \"mvp2_grpo_extract_r3\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"mvp2_grpo_flatnli_r4\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_kl001\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_r5\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"mvp2_grpo_flatnli_r3\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_sft_eval_r2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4057, \"ign_f1\": 0.4057, \"evi_f1\": 0.7979, \"edcr\": 0.7118, \"precision\": 0.4043, \"recall\": 0.407, \"evi_precision\": 0.8035, \"evi_recall\": 0.7924, \"format_ok_rate\": 0.998, \"format_compliance_rate\": 0.626, \"n_parseable\": 617, \"n_truncated\": 367, \"n_predictions\": 18815, \"inference_time_seconds\": 6484.7}}, \"mvp2_sft_eval\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_flatnli_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_extract_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_r4\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_extract\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp2_grpo_flatnli\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_r3\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_r2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced_r1\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp2_grpo_ced\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"precompute_nli_train\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp2_sft_warmup\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_loss\": 0.72, \"accuracy\": 0.835}}, \"smoke_test_grpo\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"mvp1_ced_signal\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"mean_margin\": 0.48, \"discrimination_accuracy\": 0.815, \"pearson_r_margin_jaccard\": 0.34, \"pass\": true}}}, \"count\": 331, \"total\": 331, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 1.084}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-22T16:12:40.046Z_

<details><summary>↩ Tool result · `toolu_0148xkKq6gE1tjd2Yh7s9S3A`</summary>

```text
docs/paper/sections/analysis.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "9f8eaf2c-0cd1-4353-839a-d20a9e31af78",
  "tool_use_result": {
    "filenames": [
      "docs/paper/sections/analysis.tex"
    ],
    "durationMs": 32,
    "numFiles": 1,
    "truncated": false
  }
}
```

</details>

---

### Assistant

_source line 14_

<details><summary>Logged reasoning block</summary>

```text
The first registry query returned 0 results for "plan010_nli_large_eval_r2" - maybe the exp_id is slightly different. Let me search the full registry dump and also read the analysis.tex file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "9157e8fc-1a4a-4056-b649-913074a3adba",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QD4tBry8tWMsQiaLCA2UuF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 835,
      "cache_read_input_tokens": 25481,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 835
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

_source line 15_

Registry 查询 plan010_nli_large_eval_r2 返回 0 结果，可能 exp_id 略有不同。让我搜索 registry 并读取 analysis.tex。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "cf96820f-38b2-46fb-b1c0-d000e8a1be2a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QD4tBry8tWMsQiaLCA2UuF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 835,
      "cache_read_input_tokens": 25481,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 835
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

_source line 16_

<details open><summary>🔧 Tool call — Bash · `toolu_01EZ4hQPwM2mq7fDR2YnTbKW`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/e41b22b4-8852-4330-9d93-534a6630d550/tool-results/mcp-agent-ml-research-read_registry-1779466359990.txt | python3 -c \"\nimport json, sys\ndata = json.loads(json.loads(sys.stdin.read())['result'])\nexps = data['data']['experiments']\n# Find NLI large related experiments\nfor eid, exp in exps.items():\n    if 'nli' in eid.lower() or 'large' in eid.lower():\n        print(f'{eid}: status={exp.get(\\\"status\\\")}, metrics={exp.get(\\\"metrics\\\")}, desc={exp.get(\\\"description\\\",\\\"\\\")[:120]}')\n\"",
  "description": "Search registry for NLI large experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "fa7ab8cb-6d6f-4e15-848b-367adf61ea13",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QD4tBry8tWMsQiaLCA2UuF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 835,
      "cache_read_input_tokens": 25481,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 835
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

_source line 17 · 2026-05-22T16:12:47.401Z_

<details><summary>↩ Tool result · `toolu_01EZ4hQPwM2mq7fDR2YnTbKW`</summary>

```text
plan010_nli_large_eval_r2: status=DONE, metrics={'f1': 0.4636, 'ign_f1': 0.4533, 'evi_f1_joint': 0.3606, 'evi_f1_tp': 0.8194, 'edcr': 0.653, 'format_compliance': 1, 'n_truncated': 180, 'n_predictions': 14870, 'inference_time_s': 10064}, desc=
plan010_nli_large_eval: status=DONE, metrics=None, desc=
plan010_nli_large_ablation: status=DONE, metrics=None, desc=
reeval_flat_nli_s42: status=DONE, metrics={'ign_f1': 0.4448, 'rel_f1': 0.4535, 'evi_f1': 0.8039, 'evi_f1_joint': 0.3558, 'edcr': 0.6458, 'format_compliance_rate': 1, 'field_compliance_rate': 0.7787, 'n_truncated': 205, 'inference_time_seconds': 13253.1}, desc=
reeval_flat_nli_s44: status=DONE, metrics=None, desc=
reeval_flat_nli_s43_r2: status=DONE, metrics={'rel_f1': 0.4586, 'rel_precision': 0.4732, 'rel_recall': 0.4449, 'ign_f1': 0.4503, 'evi_f1': 0.8113, 'evi_precision': 0.8035, 'evi_recall': 0.8192, 'evi_f1_joint': 0.358, 'edcr': 0.6552, 'format_ok_rate': 0.999, 'n_truncated': 184, 'n_predictions': 15015}, desc=
eval_flat_nli_seed45: status=DONE, metrics={'rel_f1': 0.455052, 'ign_f1': 0.446181, 'evi_f1': 0.815399, 'edcr': 0.652133, 'evi_f1_joint': 0.355612}, desc=
eval_flat_nli_s44: status=DONE, metrics={'rel_f1': 0.461506, 'ign_f1': 0.452126, 'evi_f1': 0.813123, 'edcr': 0.645808, 'evi_f1_joint': 0.359673}, desc=
reeval_flat_nli_s43: status=DONE, metrics={'rel_f1': 0.4523, 'ign_f1': 0.4523, 'evi_f1': 0.8158, 'edcr': 0.6505, 'num_preds': 15357, 'format_ok': '984/985', 'truncated': '211/985', 'inference_time_s': 3515.8}, desc=
eval_flat_nli_seed44: status=DONE, metrics=None, desc=
plan_001_flat_nli_seed44: status=DONE, metrics={'train_loss': 0.6247, 'eval_loss': 0.7564, 'eval_mean_token_accuracy': 0.8299, 'task_eval_f1_ep1': 0.4306, 'task_eval_f1_ep2': 0.4884, 'task_eval_f1_ep3': 0.4897, 'task_eval_evi_f1_ep3': 0.78, 'task_eval_edcr_ep3': 0.6596, 'task_eval_ign_f1_ep3': 0.4897, 'train_runtime_sec': 6197, 'num_epochs': 3, 'total_steps': 507}, desc=
plan_001_flat_nli_seed45: status=DONE, metrics={'task_eval_rel_f1': 0.4876, 'task_eval_evi_f1': 0.7927, 'task_eval_edcr': 0.6517, 'train_loss': 0.6245, 'runtime_hours': 1.69, 'note': 'task-eval on 50 docs only, full dev eval needed'}, desc=
eval_plan_001_flat_nli_s43: status=DONE, metrics={'rel_f1': 0.0022, 'ign_f1': 0.0022, 'evi_f1': 0.8533, 'edcr': 0.9982, 'num_preds': 17285, 'format_ok': '981/985', 'truncated': '251/985', 'tp': 32, 'note': 'INVALID — missing --sft_adapter, same bug as DPO 1ep eval'}, desc=
plan_001_flat_nli_seed43: status=DONE, metrics={'train_loss_final': 0.6257, 'train_loss_min': 0.5895, 'eval_loss_epoch3': 0.7567, 'eval_accuracy_epoch3': 0.8298, 'total_steps': 507, 'epochs': 3, 'train_runtime_seconds': 6880, 'task_eval_f1_ep1': 0.4825, 'task_eval_f1_ep2': 0.4542, 'task_eval_f1_ep3': 0.4866, 'task_eval_evi_f1_ep3': 0.7834, 'task_eval_edcr_ep3': 0.6402, 'task_eval_note': '50-doc subset, not full dev'}, desc=
plan_009_flatnli_reward_eval_r2: status=DONE, metrics=None, desc=
plan_009_flatnli_reward_eval: status=DONE, metrics=None, desc=
plan_001_rsft_flat_nli: status=DONE, metrics={'train_loss': 0.6238, 'train_loss_min': 0.5803, 'mean_token_accuracy': 0.8528, 'train_runtime_sec': 2946, 'epochs': 3, 'total_steps': 507, 'samples': 2691}, desc=
eval_plan_001_flat_nli: status=DONE, metrics={'rel_f1': 0.4539, 'ign_f1': 0.4539, 'evi_f1': 0.8043, 'edcr': 0.6431, 'precision': 0.4671, 'recall': 0.4414, 'evi_precision': 0.8143, 'evi_recall': 0.7945, 'format_ok_rate': 1, 'n_truncated': 199, 'n_documents': 985, 'n_predictions': 15294, 'inference_time_seconds': 3631}, desc=
plan_001_flat_nli_scoring: status=DONE, metrics={'total_scored': 21728, 'selected_samples': 2691, 'selection_rate': 0.124, 'selection_strategy': 'top_k=1', 'f1_threshold': 0.1, 'output_path': '/root/autodl-tmp/rsft_filtered_flat_nli/rsft_train.jsonl'}, desc=
mvp2_grpo_flatnli_r6: status=DONE, metrics={'steps_completed': 25, 'final_frac_zero_std': 0.9, 'final_f1_reward': 0, 'final_flat_nli_reward': 0, 'final_format_reward': 0.293, 'collapse_step': 25}, desc=
mvp2_grpo_flatnli_r5: status=DONE, metrics=None, desc=
mvp2_grpo_flatnli_r4: status=DONE, metrics=None, desc=
mvp2_grpo_flatnli_r3: status=DONE, metrics=None, desc=
mvp2_grpo_flatnli_r2: status=DONE, metrics=None, desc=
mvp2_grpo_flatnli: status=DONE, metrics=None, desc=
precompute_nli_train: status=DONE, metrics=None, desc=
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "eb818470-947c-4208-b03c-be7ff4a01d59",
  "tool_use_result": {
    "stdout": "plan010_nli_large_eval_r2: status=DONE, metrics={'f1': 0.4636, 'ign_f1': 0.4533, 'evi_f1_joint': 0.3606, 'evi_f1_tp': 0.8194, 'edcr': 0.653, 'format_compliance': 1, 'n_truncated': 180, 'n_predictions': 14870, 'inference_time_s': 10064}, desc=\nplan010_nli_large_eval: status=DONE, metrics=None, desc=\nplan010_nli_large_ablation: status=DONE, metrics=None, desc=\nreeval_flat_nli_s42: status=DONE, metrics={'ign_f1': 0.4448, 'rel_f1': 0.4535, 'evi_f1': 0.8039, 'evi_f1_joint': 0.3558, 'edcr': 0.6458, 'format_compliance_rate': 1, 'field_compliance_rate': 0.7787, 'n_truncated': 205, 'inference_time_seconds': 13253.1}, desc=\nreeval_flat_nli_s44: status=DONE, metrics=None, desc=\nreeval_flat_nli_s43_r2: status=DONE, metrics={'rel_f1': 0.4586, 'rel_precision': 0.4732, 'rel_recall': 0.4449, 'ign_f1': 0.4503, 'evi_f1': 0.8113, 'evi_precision': 0.8035, 'evi_recall': 0.8192, 'evi_f1_joint': 0.358, 'edcr': 0.6552, 'format_ok_rate': 0.999, 'n_truncated': 184, 'n_predictions': 15015}, desc=\neval_flat_nli_seed45: status=DONE, metrics={'rel_f1': 0.455052, 'ign_f1': 0.446181, 'evi_f1': 0.815399, 'edcr': 0.652133, 'evi_f1_joint': 0.355612}, desc=\neval_flat_nli_s44: status=DONE, metrics={'rel_f1': 0.461506, 'ign_f1': 0.452126, 'evi_f1': 0.813123, 'edcr': 0.645808, 'evi_f1_joint': 0.359673}, desc=\nreeval_flat_nli_s43: status=DONE, metrics={'rel_f1': 0.4523, 'ign_f1': 0.4523, 'evi_f1': 0.8158, 'edcr': 0.6505, 'num_preds': 15357, 'format_ok': '984/985', 'truncated': '211/985', 'inference_time_s': 3515.8}, desc=\neval_flat_nli_seed44: status=DONE, metrics=None, desc=\nplan_001_flat_nli_seed44: status=DONE, metrics={'train_loss': 0.6247, 'eval_loss': 0.7564, 'eval_mean_token_accuracy': 0.8299, 'task_eval_f1_ep1': 0.4306, 'task_eval_f1_ep2': 0.4884, 'task_eval_f1_ep3': 0.4897, 'task_eval_evi_f1_ep3': 0.78, 'task_eval_edcr_ep3': 0.6596, 'task_eval_ign_f1_ep3': 0.4897, 'train_runtime_sec': 6197, 'num_epochs': 3, 'total_steps': 507}, desc=\nplan_001_flat_nli_seed45: status=DONE, metrics={'task_eval_rel_f1': 0.4876, 'task_eval_evi_f1': 0.7927, 'task_eval_edcr': 0.6517, 'train_loss': 0.6245, 'runtime_hours': 1.69, 'note': 'task-eval on 50 docs only, full dev eval needed'}, desc=\neval_plan_001_flat_nli_s43: status=DONE, metrics={'rel_f1': 0.0022, 'ign_f1': 0.0022, 'evi_f1': 0.8533, 'edcr': 0.9982, 'num_preds': 17285, 'format_ok': '981/985', 'truncated': '251/985', 'tp': 32, 'note': 'INVALID — missing --sft_adapter, same bug as DPO 1ep eval'}, desc=\nplan_001_flat_nli_seed43: status=DONE, metrics={'train_loss_final': 0.6257, 'train_loss_min': 0.5895, 'eval_loss_epoch3': 0.7567, 'eval_accuracy_epoch3': 0.8298, 'total_steps': 507, 'epochs': 3, 'train_runtime_seconds': 6880, 'task_eval_f1_ep1': 0.4825, 'task_eval_f1_ep2': 0.4542, 'task_eval_f1_ep3': 0.4866, 'task_eval_evi_f1_ep3': 0.7834, 'task_eval_edcr_ep3': 0.6402, 'task_eval_note': '50-doc subset, not full dev'}, desc=\nplan_009_flatnli_reward_eval_r2: status=DONE, metrics=None, desc=\nplan_009_flatnli_reward_eval: status=DONE, metrics=None, desc=\nplan_001_rsft_flat_nli: status=DONE, metrics={'train_loss': 0.6238, 'train_loss_min': 0.5803, 'mean_token_accuracy': 0.8528, 'train_runtime_sec': 2946, 'epochs': 3, 'total_steps': 507, 'samples': 2691}, desc=\neval_plan_001_flat_nli: status=DONE, metrics={'rel_f1': 0.4539, 'ign_f1': 0.4539, 'evi_f1': 0.8043, 'edcr': 0.6431, 'precision': 0.4671, 'recall': 0.4414, 'evi_precision': 0.8143, 'evi_recall': 0.7945, 'format_ok_rate': 1, 'n_truncated': 199, 'n_documents': 985, 'n_predictions': 15294, 'inference_time_seconds': 3631}, desc=\nplan_001_flat_nli_scoring: status=DONE, metrics={'total_scored': 21728, 'selected_samples': 2691, 'selection_rate': 0.124, 'selection_strategy': 'top_k=1', 'f1_threshold': 0.1, 'output_path': '/root/autodl-tmp/rsft_filtered_flat_nli/rsft_train.jsonl'}, desc=\nmvp2_grpo_flatnli_r6: status=DONE, metrics={'steps_completed': 25, 'final_frac_zero_std': 0.9, 'final_f1_reward': 0, 'final_flat_nli_reward': 0, 'final_format_reward': 0.293, 'collapse_step': 25}, desc=\nmvp2_grpo_flatnli_r5: status=DONE, metrics=None, desc=\nmvp2_grpo_flatnli_r4: status=DONE, metrics=None, desc=\nmvp2_grpo_flatnli_r3: status=DONE, metrics=None, desc=\nmvp2_grpo_flatnli_r2: status=DONE, metrics=None, desc=\nmvp2_grpo_flatnli: status=DONE, metrics=None, desc=\nprecompute_nli_train: status=DONE, metrics=None, desc=",
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

_source line 18_

<details open><summary>🔧 Tool call — Read · `toolu_01CWevmzfn6batDrRPNy2jMK`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "021674c0-9e21-468c-9a2f-1534429d065a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QD4tBry8tWMsQiaLCA2UuF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 835,
      "cache_read_input_tokens": 25481,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 835
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

_source line 19 · 2026-05-22T16:12:47.496Z_

<details><summary>↩ Tool result · `toolu_01CWevmzfn6batDrRPNy2jMK`</summary>

```text
1	\section{Analysis}
2	\label{sec:analysis}
3	
4	\paragraph{EDCR as a diagnostic.}
5	EDCR (\S\ref{sec:edcr}) correlates with extraction quality at two levels: cross-method ($\rho = -0.89$, $n = 7$, $p = 0.007$; Table~\ref{tab:spectrum}) and per-relation ($\rho = -0.79$, $n = 76$, $p < 0.001$), the latter providing validation independent of method-level sample size and orthogonal to Evi-F1 ($\rho = -0.06$, $p = 0.58$; Appendix~\ref{sec:edcr_per_relation}). RSFT avoids decoupling because discrete output selection cannot exploit the extraction-evidence trade-off (Appendix~\ref{sec:rsft_theory}). CED operates effectively at the response level but fails at sentence-level granularity (Evi-F1 $-$7.7pp), as filtering individual sentences disrupts co-reference chains.
6	
7	\paragraph{Ablation.}
8	CED and flat-NLI produce comparable RSFT performance (Rel-F1 45.63 vs.\ 45.61); stricter selection ($k{=}1$) outperforms $k{=}3$ by 1.02 Ign-F1 despite 2.96$\times$ fewer examples; CED filtering is insensitive to NLI scorer capacity (+1.10pp with DeBERTa-v3-large vs.\ v3-base, within seed noise; Appendix~\ref{sec:ablation_full}).
9	
10	\paragraph{Error patterns.}
11	RSFT reduces truncation FN, hallucinated FP, and duplicates by 6--22\% across scales, but evidence quality is unchanged ($\Delta < 0.4$pp; Appendix~\ref{sec:error_analysis}). RSFT improves \emph{what} the model extracts but not \emph{how well} it grounds extractions.
12	
13	\paragraph{Practical implications.}
14	Three guidelines for evidence-grounded IE: (1) avoid online RL for multi-objective generation where capability coupling matters; (2) prefer RSFT with strict selection ($k{=}1$) over training data quantity (7.5--17$\times$ Qwen3 variance compression, 4.6$\times$ on LLaMA); (3) consider CED reranking at inference for deployment scenarios requiring both extraction accuracy and evidence quality.
15	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "9180a013-41da-40ce-95fc-32aa3d6f4b9b",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/analysis.tex",
      "content": "\\section{Analysis}\n\\label{sec:analysis}\n\n\\paragraph{EDCR as a diagnostic.}\nEDCR (\\S\\ref{sec:edcr}) correlates with extraction quality at two levels: cross-method ($\\rho = -0.89$, $n = 7$, $p = 0.007$; Table~\\ref{tab:spectrum}) and per-relation ($\\rho = -0.79$, $n = 76$, $p < 0.001$), the latter providing validation independent of method-level sample size and orthogonal to Evi-F1 ($\\rho = -0.06$, $p = 0.58$; Appendix~\\ref{sec:edcr_per_relation}). RSFT avoids decoupling because discrete output selection cannot exploit the extraction-evidence trade-off (Appendix~\\ref{sec:rsft_theory}). CED operates effectively at the response level but fails at sentence-level granularity (Evi-F1 $-$7.7pp), as filtering individual sentences disrupts co-reference chains.\n\n\\paragraph{Ablation.}\nCED and flat-NLI produce comparable RSFT performance (Rel-F1 45.63 vs.\\ 45.61); stricter selection ($k{=}1$) outperforms $k{=}3$ by 1.02 Ign-F1 despite 2.96$\\times$ fewer examples; CED filtering is insensitive to NLI scorer capacity (+1.10pp with DeBERTa-v3-large vs.\\ v3-base, within seed noise; Appendix~\\ref{sec:ablation_full}).\n\n\\paragraph{Error patterns.}\nRSFT reduces truncation FN, hallucinated FP, and duplicates by 6--22\\% across scales, but evidence quality is unchanged ($\\Delta < 0.4$pp; Appendix~\\ref{sec:error_analysis}). RSFT improves \\emph{what} the model extracts but not \\emph{how well} it grounds extractions.\n\n\\paragraph{Practical implications.}\nThree guidelines for evidence-grounded IE: (1) avoid online RL for multi-objective generation where capability coupling matters; (2) prefer RSFT with strict selection ($k{=}1$) over training data quantity (7.5--17$\\times$ Qwen3 variance compression, 4.6$\\times$ on LLaMA); (3) consider CED reranking at inference for deployment scenarios requiring both extraction accuracy and evidence quality.\n",
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

_source line 20_

<details><summary>Logged reasoning block</summary>

```text
Now I can see the analysis.tex line 8 says:

"CED filtering is insensitive to NLI scorer capacity (+1.10pp with DeBERTa-v3-large vs. v3-base, within seed noise; Appendix~\ref{sec:ablation_full})"

The claim is +1.10pp. Let me check the registry data:

For plan010_nli_large_eval_r2 (DeBERTa-v3-large):
- f1: 0.4636
- ign_f1: 0.4533
- evi_f1_joint: 0.3606


- evi_f1_tp: 0.8194
- edcr: 0.653

Now I need to find the baseline with DeBERTa-v3-base to verify this +1.10pp difference. The claim is specifically about CED filtering performance across these two model sizes, so I'm looking for the corresponding base model results.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "92c7a686-2b2c-46e8-b57d-4741be0f686f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014pT2bs13cAdcTJopSceuit",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3376,
      "cache_read_input_tokens": 26316,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3376
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

_source line 21_

找到 analysis.tex L8 原文。现在需要找 CED baseline（DeBERTa-v3-base）实验。让我搜索 registry 中的 CED 相关实验。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "ddbe8a03-38c9-460d-b2ea-a59e0bebf284",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014pT2bs13cAdcTJopSceuit",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3376,
      "cache_read_input_tokens": 26316,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3376
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

_source line 22_

<details open><summary>🔧 Tool call — Bash · `toolu_01EWW4eE6MiaSmR2nJUawYMT`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/e41b22b4-8852-4330-9d93-534a6630d550/tool-results/mcp-agent-ml-research-read_registry-1779466359990.txt | python3 -c \"\nimport json, sys\ndata = json.loads(json.loads(sys.stdin.read())['result'])\nexps = data['data']['experiments']\n# Find CED related experiments\nfor eid, exp in exps.items():\n    if 'ced' in eid.lower() or 'plan010' in eid.lower() or 'plan_010' in eid.lower():\n        print(f'{eid}: status={exp.get(\\\"status\\\")}, metrics={exp.get(\\\"metrics\\\")}, desc={exp.get(\\\"description\\\",\\\"\\\")[:200]}')\n\"",
  "description": "Search registry for CED and plan010 experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "de252beb-7454-4eb2-a640-dc7728bd3d22",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014pT2bs13cAdcTJopSceuit",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3376,
      "cache_read_input_tokens": 26316,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3376
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

_source line 23 · 2026-05-22T16:12:58.557Z_

<details><summary>↩ Tool result · `toolu_01EWW4eE6MiaSmR2nJUawYMT`</summary>

```text
dev_eval_4b_rsft_ced_s42_v2: status=DONE, metrics={'ign_f1': 0.4388, 'evi_f1': 0.8069, 'format_compliance_rate': 1, 'n_truncated': 143, 'n_documents': 985}, desc=
retrain_4b_rsft_ced_s42_v2: status=DONE, metrics={'final_loss': 0.5711, 'token_accuracy': 0.8639, 'train_loss_avg': 0.6114, 'total_steps': 510, 'epochs': 3, 'train_runtime_sec': 2348}, desc=
retrain_4b_rsft_ced_s42: status=DONE, metrics=None, desc=
d112_rsft_s44_ced_score: status=DONE, metrics={'total_scored': 24216, 'selected_count': 3014, 'selection_rate': 0.124, 'mean_f1': 0.676, 'mean_ced': 0.676}, desc=
plan017_14b_ced_scoring: status=DONE, metrics={'total_scored': 24216, 'unique_docs_total': 3027, 'selected_count': 3015, 'unique_docs_selected': 3015, 'selection_rate': 0.1245, 'all_mean_f1': 0.616, 'all_mean_ced': 0.568, 'all_mean_combined': 0.673, 'selected_mean_f1': 0.73, 'selected_mean_ced': 0.69, 'selected_mean_combined': 0.768, 'selected_median_f1': 0.75, 'selected_median_ced': 0.71, 'f1_filter_dropped_gens': 497, 'f1_filter_dropped_docs': 12, 'truncated_count': 1701, 'truncated_ratio': 0.07, 'truncated_mean_f1': 0.487, 'non_truncated_mean_f1': 0.625, 'truncation_f1_gap': 0.139, 'format_reward_mean': 0.9996, 'output_file': '/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl', 'output_size_mb': 9.1, 'runtime_hours': 1}, desc=
plan010_nli_large_eval_r2: status=DONE, metrics={'f1': 0.4636, 'ign_f1': 0.4533, 'evi_f1_joint': 0.3606, 'evi_f1_tp': 0.8194, 'edcr': 0.653, 'format_compliance': 1, 'n_truncated': 180, 'n_predictions': 14870, 'inference_time_s': 10064}, desc=
plan010_nli_large_eval: status=DONE, metrics=None, desc=
plan010_nli_large_ablation: status=DONE, metrics=None, desc=
lead1_ced_evidence_filter: status=DONE, metrics={'baseline_f1': 0.4601, 'baseline_ign_f1': 0.4512, 'baseline_evi_f1': 0.8063, 'baseline_edcr': 0.6542, 'tau_0.3_evi_f1': 0.7301, 'tau_0.3_edcr': 0.5797, 'tau_0.5_evi_f1': 0.7297, 'tau_0.5_edcr': 0.5784, 'tau_0.7_evi_f1': 0.7287, 'tau_0.7_edcr': 0.5776, 'evidence_kept_pct_tau_0.5': 61.9, 'verdict': 'CED filter removes ~38% evidence but drops Evi-F1 by 7.7pp and EDCR by 7.6pp'}, desc=
lead2_rsft_grpo_ced_r2: status=DONE, metrics=None, desc=
lead2_rsft_grpo_ced: status=DONE, metrics=None, desc=
plan_006_qwen3_8b_ced_scoring: status=DONE, metrics={'output_samples': 9041, 'input_candidates': 24216, 'scoring_mode': 'ced', 'tau': 0.5, 'top_k': 3}, desc=
plan_016_llama_ced_scoring: status=DONE, metrics=None, desc=
plan_006_qwen3_1_7b_ced_scoring: status=DONE, metrics={'total_records': 24216, 'selected': 9042, 'unique_docs': 3021, 'selection_rate': 0.373, 'mean_f1_reward': 0.592, 'mean_ced_reward': 0.559, 'mean_combined_score': 0.66, 'truncated_count': 2920, 'truncated_mean_f1': 0.439, 'non_truncated_mean_f1': 0.613}, desc=
reeval_ced_s44: status=DONE, metrics={'ign_f1': 0.4511, 'rel_f1': 0.4621, 'evi_f1': 0.805, 'evi_f1_joint': 0.3677, 'edcr': 0.635, 'format_compliance_rate': 1, 'field_compliance_rate': 0.802, 'n_truncated': 190, 'inference_time_seconds': 13077.6}, desc=
reeval_ced_s42: status=DONE, metrics={'ign_f1': 0.4423, 'rel_f1': 0.4517, 'evi_f1': 0.8175, 'evi_f1_joint': 0.3518, 'edcr': 0.6569, 'format_compliance_rate': 1, 'field_compliance_rate': 0.7756, 'n_truncated': 214, 'inference_time_seconds': 10815.5}, desc=
eval_rsft_ced_s45: status=DONE, metrics={'rel_f1': 0.4514, 'ign_f1': 0.4416, 'evi_f1': 0.8174, 'rel_p': 0.4718, 'rel_r': 0.4326, 'edcr': 0.655, 'evi_f1_joint': 0.3558, 'n_truncated': 206, 'format_ok_rate': 1}, desc=
eval_rsft_ced_s43: status=DONE, metrics={'rel_f1': 0.4601, 'ign_f1': 0.4512, 'precision': 0.4696, 'recall': 0.4509, 'evi_f1': 0.8063, 'evi_precision': 0.8025, 'evi_recall': 0.8101, 'edcr': 0.6542, 'evi_f1_joint': 0.3605, 'format_ok_rate': 1, 'n_truncated': 184, 'n_predictions': 15051, 'inference_time_seconds': 10768.2}, desc=
mvp2_ced_reranker_poc: status=DONE, metrics={'ced_reranker_rel_f1': 0.486367, 'ced_reranker_ign_f1': 0.473634, 'ced_reranker_evi_f1': 0.8188, 'oracle_rel_f1': 0.623746, 'oracle_ign_f1': 0.612518, 'random_rel_f1': 0.453783, 'random_ign_f1': 0.439677}, desc=
rsft_ced_s45_train_r4: status=DONE, metrics={'training_completed': True, 'checkpoint': 'checkpoint-510', 'note': 'Training metrics not captured (r4 retry after OOM). Eval running as eval_rsft_ced_s45.'}, desc=
rsft_ced_s43_train_r3: status=DONE, metrics={'train_loss': 0.6151, 'eval_loss': 0.7618, 'task_eval_f1': 0.5026, 'task_eval_ign_f1': 0.4932, 'task_eval_evi_f1': 0.7624, 'task_eval_edcr': 0.6516, 'total_steps': 510, 'epochs': 3, 'training_hours': 1.82}, desc=
rsft_ced_s45_train_r3: status=DONE, metrics=None, desc=
rsft_ced_s45_train_r2: status=DONE, metrics=None, desc=
rsft_ced_s43_train_r2: status=DONE, metrics=None, desc=
rsft_ced_s43_train: status=DONE, metrics=None, desc=
rsft_ced_s45_train: status=DONE, metrics=None, desc=
plan_012_dpo_ced: status=DONE, metrics={'rel_f1': 0.3429, 'evi_f1': 0.8403, 'edcr': 0.7294, 'format_ok_rate': 0.995, 'checkpoint': 'checkpoint-501', 'rewards_accuracy': 1, 'margins': 9.01}, desc=
plan_012_dpo_ced_1ep: status=DONE, metrics={'rel_f1': 0.0022, 'evi_f1': 0.75, 'edcr': 0.9982, 'format_ok': '981/985', 'truncated': '358/985', 'tp': 34, 'n_preds': 19265, 'inference_time_s': 3643, 'train_loss_final': 0.59, 'rewards_accuracy': 0.82, 'rewards_margins': 0.86, 'total_steps': 167, 'training_time_min': 33}, desc=
eval_plan_012_dpo_ced_1ep: status=DONE, metrics={'rel_f1': 0.0022, 'ign_f1': 0.0022, 'evi_f1': 0.75, 'edcr': 0.9982, 'num_preds': 19265, 'format_ok': '981/985', 'truncated': '358/985', 'tp': 34, 'inference_time_s': 3643}, desc=
eval_plan_012_dpo_ced_ckpt400: status=DONE, metrics=None, desc=
mvp2_rsft_ced_scoring_topk3_r2: status=DONE, metrics={'input_generations': 21728, 'selected_samples': 8037, 'unique_docs': 2691, 'selection_rate': 0.37, 'mean_f1': 0.5761, 'mean_ced': 0.6205, 'mean_combined': 0.6787, 'f1_range_p25': 0.444, 'f1_range_p75': 0.717, 'ced_range_p25': 0.487, 'ced_range_p75': 0.774, 'truncated_samples': 1924, 'truncated_pct': 8.9, 'selection_strategy': 'top_k=3', 'f1_threshold': 0.1, 'topk1_samples': 2718, 'data_multiplier': 2.96}, desc=
mvp2_rsft_ced_scoring_topk3: status=DONE, metrics=None, desc=
mvp2_eval_ced_kl001_r4_last: status=DONE, metrics=None, desc=
mvp2_grpo_ced_kl001_r3: status=DONE, metrics=None, desc=
mvp2_grpo_ced_kl001_r2: status=DONE, metrics=None, desc=
mvp2_rsft_ced_scoring: status=DONE, metrics={'input_generations': 21952, 'selected_samples': 2718, 'unique_docs': 2691, 'selection_rate': 0.124, 'mean_f1': 0.6157, 'mean_ced': 0.6683, 'f1_range': [0.1026, 1], 'zero_f1_samples': 0, 'selection_strategy': 'top_k=1', 'f1_threshold': 0.1}, desc=
mvp2_grpo_ced_lr5e6_r1: status=DONE, metrics=None, desc=
mvp2_grpo_ced_lr5e6_rp_r2: status=DONE, metrics=None, desc=
mvp2_eval_ced_kl001_r4_multi: status=DONE, metrics={'checkpoint-10': {'f1': 0.003, 'ign_f1': 0.003, 'evi_f1': 0.72, 'edcr': 0.9983, 'format_ok_rate': 0.999}, 'checkpoint-20': {'f1': 0.0088, 'ign_f1': 0.0088, 'evi_f1': 0.423, 'edcr': 0.9954, 'format_ok_rate': 0.999}, 'checkpoint-30': {'f1': 0.0338, 'ign_f1': 0.0338, 'evi_f1': 0.5889, 'edcr': 0.9798, 'format_ok_rate': 1}, 'checkpoint-50': {'f1': 0.1563, 'ign_f1': 0.1563, 'evi_f1': 0.5643, 'edcr': 0.8858, 'format_ok_rate': 0.999}, 'checkpoint-60': {'f1': 0.1467, 'ign_f1': 0.1467, 'evi_f1': 0.5763, 'edcr': 0.9062, 'format_ok_rate': 1}, 'checkpoint-90': {'f1': 0.2108, 'ign_f1': 0.2108, 'evi_f1': 0.5666, 'edcr': 0.8584, 'format_ok_rate': 1}}, desc=
mvp2_grpo_ced_lr5e6_rp_r1: status=DONE, metrics=None, desc=
mvp2_grpo_ced_lr5e6_p1_r1: status=DONE, metrics=None, desc=
mvp2_eval_ced_kl001_r4_step90: status=DONE, metrics={'rel_f1': 0.2108, 'ign_f1': 0.2108, 'evi_f1': 0.5666, 'edcr': 0.8584, 'pred_count': 11160, 'n_truncated': 22, 'format_ok_rate': 1, 'n_documents': 985}, desc=
mvp2_eval_ced_kl001_r4_ckpt7080: status=DONE, metrics=None, desc=
mvp2_eval_ced_kl001_r4_high: status=DONE, metrics={'checkpoint_60': {'rel_f1': 0.1467, 'ign_f1': 0.1467, 'precision': 0.1909, 'recall': 0.1192, 'evi_f1': 0.5763, 'edcr': 0.9062, 'pred_count': 10041, 'gold_count': 12151, 'n_truncated': 16, 'format_ok_rate': 1}, 'note': 'Only ckpt-60 completed. Process died during ckpt-70 inference at 8% (5/62 batch). ckpt-80/90 never started.'}, desc=
mvp2_eval_ced_kl001_r4_step100: status=DONE, metrics={'rel_f1': 0.2167, 'ign_f1': 0.2167, 'precision': 0.2849, 'recall': 0.1749, 'evi_f1': 0.5746, 'evi_precision': 0.5244, 'evi_recall': 0.6353, 'edcr': 0.8539, 'pred_count': 7460, 'gold_count': 12151, 'tp': 2125, 'n_truncated': 21, 'format_ok_rate': 1}, desc=
mvp2_eval_ced_kl001_r4_ckpt90: status=DONE, metrics=None, desc=
mvp2_eval_ced_kl001_r4_ckpt10: status=DONE, metrics={'rel_f1': 0.00296, 'rel_precision': 0.00314, 'rel_recall': 0.0028, 'evi_f1': 0.72, 'evi_precision': 0.6429, 'evi_recall': 0.8182, 'edcr': 0.9983, 'n_parseable': 984, 'n_truncated': 24, 'n_predictions': 11621, 'tp': 34, 'pred_count': 10839, 'gold_count': 12151, 'inference_time_seconds': 5211.4}, desc=
mvp2_eval_ced_kl001_r4_early: status=DONE, metrics={'f1': 0.1563, 'ign_f1': 0.1563, 'evi_f1': 0.5643, 'edcr': 0.8858, 'precision': 0.2356, 'recall': 0.1169, 'evi_precision': 0.4864, 'evi_recall': 0.6721, 'format_ok_rate': 0.999, 'n_parseable': 984, 'n_truncated': 11, 'n_predictions': 9250, 'tp': 1421, 'pred_count': 6032, 'gold_count': 12151}, desc=
mvp2_grpo_ced_kl001_r4: status=DONE, metrics={'final_step': 100, 'train_runtime_s': 9069.88, 'reward_final': 1.195, 'f1_reward_final': 0.573, 'ced_reward_final': 0.328, 'format_reward_final': 0.293, 'frac_zero_std_final': 0.2, 'kl_final': 0.118, 'loss_final': -0.009, 'grad_norm_final': 0.14, 'entropy_final': 0.067, 'completion_length_mean_final': 520.8, 'best_reward_step': 90, 'best_reward': 1.37, 'best_f1_reward': 0.72, 'best_ced_reward': 0.353}, desc=
mvp2_grpo_ced_kl001: status=DONE, metrics=None, desc=
mvp2_grpo_ced_r5: status=DONE, metrics=None, desc=
mvp2_grpo_ced_r4: status=DONE, metrics=None, desc=
mvp2_grpo_ced_r3: status=DONE, metrics=None, desc=
mvp2_grpo_ced_r2: status=DONE, metrics=None, desc=
mvp2_grpo_ced_r1: status=DONE, metrics=None, desc=
mvp2_grpo_ced: status=DONE, metrics=None, desc=
mvp1_ced_signal: status=DONE, metrics={'mean_margin': 0.48, 'discrimination_accuracy': 0.815, 'pearson_r_margin_jaccard': 0.34, 'pass': True}, desc=
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "eab0f31c-a23a-4e4a-8e76-f4ba037f53d5",
  "tool_use_result": {
    "stdout": "dev_eval_4b_rsft_ced_s42_v2: status=DONE, metrics={'ign_f1': 0.4388, 'evi_f1': 0.8069, 'format_compliance_rate': 1, 'n_truncated': 143, 'n_documents': 985}, desc=\nretrain_4b_rsft_ced_s42_v2: status=DONE, metrics={'final_loss': 0.5711, 'token_accuracy': 0.8639, 'train_loss_avg': 0.6114, 'total_steps': 510, 'epochs': 3, 'train_runtime_sec': 2348}, desc=\nretrain_4b_rsft_ced_s42: status=DONE, metrics=None, desc=\nd112_rsft_s44_ced_score: status=DONE, metrics={'total_scored': 24216, 'selected_count': 3014, 'selection_rate': 0.124, 'mean_f1': 0.676, 'mean_ced': 0.676}, desc=\nplan017_14b_ced_scoring: status=DONE, metrics={'total_scored': 24216, 'unique_docs_total': 3027, 'selected_count': 3015, 'unique_docs_selected': 3015, 'selection_rate': 0.1245, 'all_mean_f1': 0.616, 'all_mean_ced': 0.568, 'all_mean_combined': 0.673, 'selected_mean_f1': 0.73, 'selected_mean_ced': 0.69, 'selected_mean_combined': 0.768, 'selected_median_f1': 0.75, 'selected_median_ced': 0.71, 'f1_filter_dropped_gens': 497, 'f1_filter_dropped_docs': 12, 'truncated_count': 1701, 'truncated_ratio': 0.07, 'truncated_mean_f1': 0.487, 'non_truncated_mean_f1': 0.625, 'truncation_f1_gap': 0.139, 'format_reward_mean': 0.9996, 'output_file': '/root/autodl-tmp/rsft_scored_14b/rsft_train.jsonl', 'output_size_mb': 9.1, 'runtime_hours': 1}, desc=\nplan010_nli_large_eval_r2: status=DONE, metrics={'f1': 0.4636, 'ign_f1': 0.4533, 'evi_f1_joint': 0.3606, 'evi_f1_tp': 0.8194, 'edcr': 0.653, 'format_compliance': 1, 'n_truncated': 180, 'n_predictions': 14870, 'inference_time_s': 10064}, desc=\nplan010_nli_large_eval: status=DONE, metrics=None, desc=\nplan010_nli_large_ablation: status=DONE, metrics=None, desc=\nlead1_ced_evidence_filter: status=DONE, metrics={'baseline_f1': 0.4601, 'baseline_ign_f1': 0.4512, 'baseline_evi_f1': 0.8063, 'baseline_edcr': 0.6542, 'tau_0.3_evi_f1': 0.7301, 'tau_0.3_edcr': 0.5797, 'tau_0.5_evi_f1': 0.7297, 'tau_0.5_edcr': 0.5784, 'tau_0.7_evi_f1': 0.7287, 'tau_0.7_edcr': 0.5776, 'evidence_kept_pct_tau_0.5': 61.9, 'verdict': 'CED filter removes ~38% evidence but drops Evi-F1 by 7.7pp and EDCR by 7.6pp'}, desc=\nlead2_rsft_grpo_ced_r2: status=DONE, metrics=None, desc=\nlead2_rsft_grpo_ced: status=DONE, metrics=None, desc=\nplan_006_qwen3_8b_ced_scoring: status=DONE, metrics={'output_samples': 9041, 'input_candidates': 24216, 'scoring_mode': 'ced', 'tau': 0.5, 'top_k': 3}, desc=\nplan_016_llama_ced_scoring: status=DONE, metrics=None, desc=\nplan_006_qwen3_1_7b_ced_scoring: status=DONE, metrics={'total_records': 24216, 'selected': 9042, 'unique_docs': 3021, 'selection_rate': 0.373, 'mean_f1_reward': 0.592, 'mean_ced_reward': 0.559, 'mean_combined_score': 0.66, 'truncated_count': 2920, 'truncated_mean_f1': 0.439, 'non_truncated_mean_f1': 0.613}, desc=\nreeval_ced_s44: status=DONE, metrics={'ign_f1': 0.4511, 'rel_f1': 0.4621, 'evi_f1': 0.805, 'evi_f1_joint': 0.3677, 'edcr': 0.635, 'format_compliance_rate': 1, 'field_compliance_rate': 0.802, 'n_truncated': 190, 'inference_time_seconds': 13077.6}, desc=\nreeval_ced_s42: status=DONE, metrics={'ign_f1': 0.4423, 'rel_f1': 0.4517, 'evi_f1': 0.8175, 'evi_f1_joint': 0.3518, 'edcr': 0.6569, 'format_compliance_rate': 1, 'field_compliance_rate': 0.7756, 'n_truncated': 214, 'inference_time_seconds': 10815.5}, desc=\neval_rsft_ced_s45: status=DONE, metrics={'rel_f1': 0.4514, 'ign_f1': 0.4416, 'evi_f1': 0.8174, 'rel_p': 0.4718, 'rel_r': 0.4326, 'edcr': 0.655, 'evi_f1_joint': 0.3558, 'n_truncated': 206, 'format_ok_rate': 1}, desc=\neval_rsft_ced_s43: status=DONE, metrics={'rel_f1': 0.4601, 'ign_f1': 0.4512, 'precision': 0.4696, 'recall': 0.4509, 'evi_f1': 0.8063, 'evi_precision': 0.8025, 'evi_recall': 0.8101, 'edcr': 0.6542, 'evi_f1_joint': 0.3605, 'format_ok_rate': 1, 'n_truncated': 184, 'n_predictions': 15051, 'inference_time_seconds': 10768.2}, desc=\nmvp2_ced_reranker_poc: status=DONE, metrics={'ced_reranker_rel_f1': 0.486367, 'ced_reranker_ign_f1': 0.473634, 'ced_reranker_evi_f1': 0.8188, 'oracle_rel_f1': 0.623746, 'oracle_ign_f1': 0.612518, 'random_rel_f1': 0.453783, 'random_ign_f1': 0.439677}, desc=\nrsft_ced_s45_train_r4: status=DONE, metrics={'training_completed': True, 'checkpoint': 'checkpoint-510', 'note': 'Training metrics not captured (r4 retry after OOM). Eval running as eval_rsft_ced_s45.'}, desc=\nrsft_ced_s43_train_r3: status=DONE, metrics={'train_loss': 0.6151, 'eval_loss': 0.7618, 'task_eval_f1': 0.5026, 'task_eval_ign_f1': 0.4932, 'task_eval_evi_f1': 0.7624, 'task_eval_edcr': 0.6516, 'total_steps': 510, 'epochs': 3, 'training_hours': 1.82}, desc=\nrsft_ced_s45_train_r3: status=DONE, metrics=None, desc=\nrsft_ced_s45_train_r2: status=DONE, metrics=None, desc=\nrsft_ced_s43_train_r2: status=DONE, metrics=None, desc=\nrsft_ced_s43_train: status=DONE, metrics=None, desc=\nrsft_ced_s45_train: status=DONE, metrics=None, desc=\nplan_012_dpo_ced: status=DONE, metrics={'rel_f1': 0.3429, 'evi_f1': 0.8403, 'edcr': 0.7294, 'format_ok_rate': 0.995, 'checkpoint': 'checkpoint-501', 'rewards_accuracy': 1, 'margins': 9.01}, desc=\nplan_012_dpo_ced_1ep: status=DONE, metrics={'rel_f1': 0.0022, 'evi_f1': 0.75, 'edcr': 0.9982, 'format_ok': '981/985', 'truncated': '358/985', 'tp': 34, 'n_preds': 19265, 'inference_time_s': 3643, 'train_loss_final': 0.59, 'rewards_accuracy': 0.82, 'rewards_margins': 0.86, 'total_steps': 167, 'training_time_min': 33}, desc=\neval_plan_012_dpo_ced_1ep: status=DONE, metrics={'rel_f1': 0.0022, 'ign_f1': 0.0022, 'evi_f1': 0.75, 'edcr': 0.9982, 'num_preds': 19265, 'format_ok': '981/985', 'truncated': '358/985', 'tp': 34, 'inference_time_s': 3643}, desc=\neval_plan_012_dpo_ced_ckpt400: status=DONE, metrics=None, desc=\nmvp2_rsft_ced_scoring_topk3_r2: status=DONE, metrics={'input_generations': 21728, 'selected_samples': 8037, 'unique_docs': 2691, 'selection_rate': 0.37, 'mean_f1': 0.5761, 'mean_ced': 0.6205, 'mean_combined': 0.6787, 'f1_range_p25': 0.444, 'f1_range_p75': 0.717, 'ced_range_p25': 0.487, 'ced_range_p75': 0.774, 'truncated_samples': 1924, 'truncated_pct': 8.9, 'selection_strategy': 'top_k=3', 'f1_threshold': 0.1, 'topk1_samples': 2718, 'data_multiplier': 2.96}, desc=\nmvp2_rsft_ced_scoring_topk3: status=DONE, metrics=None, desc=\nmvp2_eval_ced_kl001_r4_last: status=DONE, metrics=None, desc=\nmvp2_grpo_ced_kl001_r3: status=DONE, metrics=None, desc=\nmvp2_grpo_ced_kl001_r2: status=DONE, metrics=None, desc=\nmvp2_rsft_ced_scoring: status=DONE, metrics={'input_generations': 21952, 'selected_samples': 2718, 'unique_docs': 2691, 'selection_rate': 0.124, 'mean_f1': 0.6157, 'mean_ced': 0.6683, 'f1_range': [0.1026, 1], 'zero_f1_samples': 0, 'selection_strategy': 'top_k=1', 'f1_threshold': 0.1}, desc=\nmvp2_grpo_ced_lr5e6_r1: status=DONE, metrics=None, desc=\nmvp2_grpo_ced_lr5e6_rp_r2: status=DONE, metrics=None, desc=\nmvp2_eval_ced_kl001_r4_multi: status=DONE, metrics={'checkpoint-10': {'f1': 0.003, 'ign_f1': 0.003, 'evi_f1': 0.72, 'edcr': 0.9983, 'format_ok_rate': 0.999}, 'checkpoint-20': {'f1': 0.0088, 'ign_f1': 0.0088, 'evi_f1': 0.423, 'edcr': 0.9954, 'format_ok_rate': 0.999}, 'checkpoint-30': {'f1': 0.0338, 'ign_f1': 0.0338, 'evi_f1': 0.5889, 'edcr': 0.9798, 'format_ok_rate': 1}, 'checkpoint-50': {'f1': 0.1563, 'ign_f1': 0.1563, 'evi_f1': 0.5643, 'edcr': 0.8858, 'format_ok_rate': 0.999}, 'checkpoint-60': {'f1': 0.1467, 'ign_f1': 0.1467, 'evi_f1': 0.5763, 'edcr': 0.9062, 'format_ok_rate': 1}, 'checkpoint-90': {'f1': 0.2108, 'ign_f1': 0.2108, 'evi_f1': 0.5666, 'edcr': 0.8584, 'format_ok_rate': 1}}, desc=\nmvp2_grpo_ced_lr5e6_rp_r1: status=DONE, metrics=None, desc=\nmvp2_grpo_ced_lr5e6_p1_r1: status=DONE, metrics=None, desc=\nmvp2_eval_ced_kl001_r4_step90: status=DONE, metrics={'rel_f1': 0.2108, 'ign_f1': 0.2108, 'evi_f1': 0.5666, 'edcr': 0.8584, 'pred_count': 11160, 'n_truncated': 22, 'format_ok_rate': 1, 'n_documents': 985}, desc=\nmvp2_eval_ced_kl001_r4_ckpt7080: status=DONE, metrics=None, desc=\nmvp2_eval_ced_kl001_r4_high: status=DONE, metrics={'checkpoint_60': {'rel_f1': 0.1467, 'ign_f1': 0.1467, 'precision': 0.1909, 'recall': 0.1192, 'evi_f1': 0.5763, 'edcr': 0.9062, 'pred_count': 10041, 'gold_count': 12151, 'n_truncated': 16, 'format_ok_rate': 1}, 'note': 'Only ckpt-60 completed. Process died during ckpt-70 inference at 8% (5/62 batch). ckpt-80/90 never started.'}, desc=\nmvp2_eval_ced_kl001_r4_step100: status=DONE, metrics={'rel_f1': 0.2167, 'ign_f1': 0.2167, 'precision': 0.2849, 'recall': 0.1749, 'evi_f1': 0.5746, 'evi_precision': 0.5244, 'evi_recall': 0.6353, 'edcr': 0.8539, 'pred_count': 7460, 'gold_count': 12151, 'tp': 2125, 'n_truncated': 21, 'format_ok_rate': 1}, desc=\nmvp2_eval_ced_kl001_r4_ckpt90: status=DONE, metrics=None, desc=\nmvp2_eval_ced_kl001_r4_ckpt10: status=DONE, metrics={'rel_f1': 0.00296, 'rel_precision': 0.00314, 'rel_recall': 0.0028, 'evi_f1': 0.72, 'evi_precision': 0.6429, 'evi_recall': 0.8182, 'edcr': 0.9983, 'n_parseable': 984, 'n_truncated': 24, 'n_predictions': 11621, 'tp': 34, 'pred_count': 10839, 'gold_count': 12151, 'inference_time_seconds': 5211.4}, desc=\nmvp2_eval_ced_kl001_r4_early: status=DONE, metrics={'f1': 0.1563, 'ign_f1': 0.1563, 'evi_f1': 0.5643, 'edcr': 0.8858, 'precision': 0.2356, 'recall': 0.1169, 'evi_precision': 0.4864, 'evi_recall': 0.6721, 'format_ok_rate': 0.999, 'n_parseable': 984, 'n_truncated': 11, 'n_predictions': 9250, 'tp': 1421, 'pred_count': 6032, 'gold_count': 12151}, desc=\nmvp2_grpo_ced_kl001_r4: status=DONE, metrics={'final_step': 100, 'train_runtime_s': 9069.88, 'reward_final': 1.195, 'f1_reward_final': 0.573, 'ced_reward_final': 0.328, 'format_reward_final': 0.293, 'frac_zero_std_final': 0.2, 'kl_final': 0.118, 'loss_final': -0.009, 'grad_norm_final': 0.14, 'entropy_final': 0.067, 'completion_length_mean_final': 520.8, 'best_reward_step': 90, 'best_reward': 1.37, 'best_f1_reward': 0.72, 'best_ced_reward': 0.353}, desc=\nmvp2_grpo_ced_kl001: status=DONE, metrics=None, desc=\nmvp2_grpo_ced_r5: status=DONE, metrics=None, desc=\nmvp2_grpo_ced_r4: status=DONE, metrics=None, desc=\nmvp2_grpo_ced_r3: status=DONE, metrics=None, desc=\nmvp2_grpo_ced_r2: status=DONE, metrics=None, desc=\nmvp2_grpo_ced_r1: status=DONE, metrics=None, desc=\nmvp2_grpo_ced: status=DONE, metrics=None, desc=\nmvp1_ced_signal: status=DONE, metrics={'mean_margin': 0.48, 'discrimination_accuracy': 0.815, 'pearson_r_margin_jaccard': 0.34, 'pass': True}, desc=",
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

_source line 24_

<details><summary>Logged reasoning block</summary>

```text
Now I have the data. Let me compare the NLI large experiment with the CED baseline experiments.

The NLI large experiment is `plan010_nli_large_eval_r2`:
- f1: 0.4636
- ign_f1: 0.4533
- evi_f1_joint: 0.3606
- evi_f1_tp: 0.8194
- edcr: 0.653

For the CED baseline (DeBERTa-v3-base), I need to find the right experiment. The RSFT CED experiments are:


- eval_rsft_ced_s43: rel_f1=0.4601, ign_f1=0.4512, evi_f1=0.8063, edcr=0.6542, evi_f1_joint=0.3605
- eval_rsft_ced_s45: rel_f1=0.4514, ign_f1=0.4416, evi_f1=0.8174, edcr=0.655, evi_f1_joint=0.3558
- reeval_ced_s44: ign_f1=0.4511, rel_f1=0.4621, evi_f1=0

.805, evi_f1_joint=0.3677, edcr=0.635
- reeval_ced_s42: ign_f1=0.4423, rel_f1=0.4517, evi_f1=0.8175, evi_f1_joint=0.3518, edcr=0.6569

Now looking at the flat-NLI variant results, which show similar performance patterns across the same metrics with slight variations in the scores.

I'm also checking a few more flat-NLI runs with different seeds to see how stable these results are, and comparing them against what the analysis document claims about the relative performance between CED and flat-NLI approaches. I'm getting 45.72 for flat-NLI with all four seeds, which doesn't match the reported 45.61—maybe they're using a different subset of seeds or a different metric like ign_f1 instead of rel_f1. I'm noticing there are duplicate entries for some seeds with different evaluation versions. Let me check if they're using the reeval versions where available—s42 has a reeval entry with 0.4535, and s43 has a newer reeval_r2 version with 0.4586 instead of the older 0.4523. I'm testing different combinations of seed results to match the target score of 45.61, trying various subsets and metrics like rel_f1 versus f1, but none of the averages are landing exactly right. Let me reconsider whether the text itself might be giving me a more specific clue about what metric or filtering approach was actually used. I'm checking different metrics to find where that 1.10pp improvement comes from. Looking at ign_f1, rel_f1, and evi_f1_joint across the experiments, but none of these comparisons are yielding the claimed 1.10pp difference—the gaps are much smaller, ranging from 0.01pp to 0.73pp depending on which metric and baseline I'm comparing against.

Now I'm examining evi_f1_tp, which appears to be the metric the CED experiments labeled as "evi_f1." The plan010 large model shows 0.8194 for this metric, while the CED runs show values around 0.80-0.82, giving differences closer to 1.31pp and 1.44pp for some runs—finally getting in the ballpark of that 1.10pp figure.

I'm also checking edcr values, but those don't seem to match up either. I'm wondering if the comparison might be against a specific seed rather than an average, or if there's something else about how the NLI large experiment was set up that I'm missing.

Looking at the experiment names more carefully — "plan010_nli_large_ablation" and "plan010_nli_large_eval_r2" — this is clearly an ablation study. The claim is that upgrading from DeBERTa-v3-base to v3-large for NLI scoring in CED filtering only yields +1.10pp improvement, which falls within normal seed variation. But I need to figure out which metric this +1.10pp is measured on. I'm trying to figure out which experiment the +1.10pp improvement refers to by checking different seed combinations. Looking at the individual results — plan010 large versus CED with the same seed gives only +0.21pp, and comparing plan010 large to flat-NLI baseline yields +0.30pp, neither matching the reported 1.10pp difference. Let me examine the flat-NLI experiment results more closely to see if there's a different comparison that accounts for this gap. I'm realizing the metrics might be labeled differently across experiments—plan010 uses `f1` and `ign_f1` while CED uses `rel_f1` and `ign_f1`, where `f1` in DocRED typically refers to relation F1. So plan010 large likely has rel_f1 ≈ 0.4636 and ign_f1 = 0.4533. I should look for the ablation appendix table to understand what the +1.10pp improvement actually refers to, since I might be comparing against the wrong baseline.

Now I'm thinking about the NLI scorer capacity—the CED filtering uses different DeBERTa versions (v3-large vs v3-base) for computing CED scores, which then feeds into RSFT training and evaluation. The plan010_nli_large_eval_r2 is a single seed while the CED v3-base results span 4 seeds, so maybe the paper's comparison is across matched seeds or the +1.10pp was computed against a specific table entry that I need to locate.

Looking at the actual numbers, if I compare plan010 large (seed 43) against CED seed 45, the ign_f1 difference is around +1.17pp and rel_f1 is +1.22pp—both close to the reported +1.10pp. It could also be CED seed 42 showing a +1pp difference, so I'm trying to pin down which exact seed pairing the paper used for that comparison. Looking at the seed-specific values, the CED baseline averages around 0.4511-0.4512 across seeds s43 and s44, which aligns with the user's mention of approximately 0.4517. The +1.10pp improvement does exist in the data when comparing plan010_nli_large_eval_r2 against reeval_ced_s42, though this comparison mixes different seeds and isn't entirely apples-to-apples.

Now I'm reconsidering the experimental design—the ablation is specifically testing NLI model capacity, where they're comparing CED scoring with DeBERTa-v3-base versus DeBERTa-v3-large, then training RSFT on the differently-scored data and evaluating the results.

The core issue is figuring out which seed plan010_nli_large_eval_r2 used, since a fair comparison requires matching seeds between the large and base experiments. The +1.10pp improvement could be inflated if they're using different random seeds. I've already tried querying for the full experiment details but got no results, so I'll work with what I have: the 0.4533 vs 0.4423 difference between the large and base NLI models.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "0da05e8c-145e-48ab-bc98-4ce52aa2e47e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019nu9NuHSW32iiKkr5HmS5p",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6150,
      "cache_read_input_tokens": 29692,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6150
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

_source line 25_

找到了 NLI large 和 CED base 的 metrics。让我看看 plan010 的训练实验和 ablation 附录表格来确定用了哪个 seed。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "3e5525b0-0b64-4a76-930f-bb2ab7eee273",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019nu9NuHSW32iiKkr5HmS5p",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6150,
      "cache_read_input_tokens": 29692,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6150
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

_source line 26_

<details open><summary>🔧 Tool call — Bash · `toolu_01Py69x4GU7ykxbB9FpbAyzx`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/e41b22b4-8852-4330-9d93-534a6630d550/tool-results/mcp-agent-ml-research-read_registry-1779466359990.txt | python3 -c \"\nimport json, sys\ndata = json.loads(json.loads(sys.stdin.read())['result'])\nexps = data['data']['experiments']\n# Find plan010 related experiments (all of them)\nfor eid, exp in exps.items():\n    if 'plan010' in eid or 'plan_010' in eid:\n        print(f'=== {eid} ===')\n        for k, v in exp.items():\n            if v is not None and v != '' and v != {}:\n                print(f'  {k}: {v}')\n        print()\n\"",
  "description": "Get full details of all plan010 experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "8b7ae185-a8fd-4acf-a035-70abe022153a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019nu9NuHSW32iiKkr5HmS5p",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6150,
      "cache_read_input_tokens": 29692,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6150
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

_source line 27 · 2026-05-22T16:14:36.415Z_

<details><summary>↩ Tool result · `toolu_01Py69x4GU7ykxbB9FpbAyzx`</summary>

```text
=== plan010_nli_large_eval_r2 ===
  status: DONE
  conclusion: success
  metrics: {'f1': 0.4636, 'ign_f1': 0.4533, 'evi_f1_joint': 0.3606, 'evi_f1_tp': 0.8194, 'edcr': 0.653, 'format_compliance': 1, 'n_truncated': 180, 'n_predictions': 14870, 'inference_time_s': 10064}

=== plan010_nli_large_eval ===
  status: DONE
  conclusion: failed

=== plan010_nli_large_ablation ===
  status: DONE
  conclusion: success
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "71e241e8-4855-46ef-b6ce-61d362414c3a",
  "tool_use_result": {
    "stdout": "=== plan010_nli_large_eval_r2 ===\n  status: DONE\n  conclusion: success\n  metrics: {'f1': 0.4636, 'ign_f1': 0.4533, 'evi_f1_joint': 0.3606, 'evi_f1_tp': 0.8194, 'edcr': 0.653, 'format_compliance': 1, 'n_truncated': 180, 'n_predictions': 14870, 'inference_time_s': 10064}\n\n=== plan010_nli_large_eval ===\n  status: DONE\n  conclusion: failed\n\n=== plan010_nli_large_ablation ===\n  status: DONE\n  conclusion: success",
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

_source line 28_

<details open><summary>🔧 Tool call — Glob · `toolu_011jVH5jRSRtAT9wPUjv83Bi`</summary>

```json
{
  "pattern": "**/ablation*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "88618781-c4a6-4dfa-af6a-4661b540abc7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019nu9NuHSW32iiKkr5HmS5p",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6150,
      "cache_read_input_tokens": 29692,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6150
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

_source line 29 · 2026-05-22T16:14:36.893Z_

<details><summary>↩ Tool result · `toolu_011jVH5jRSRtAT9wPUjv83Bi`</summary>

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
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "a58a776a-7a84-42e3-98d5-ccedf2fea671",
  "tool_use_result": {
    "filenames": [],
    "durationMs": 29,
    "numFiles": 0,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 30_

<details open><summary>🔧 Tool call — Glob · `toolu_017T3prC235fRsL2YesFCaT5`</summary>

```json
{
  "pattern": "**/appendix*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "f2a13d10-2799-4b59-bd03-5d4988d064fa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KnwCY3Ui1jwDkbixFhKLi9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6092,
      "cache_read_input_tokens": 35842,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6092
      },
      "output_tokens": 58,
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

_source line 31 · 2026-05-22T16:14:40.006Z_

<details><summary>↩ Tool result · `toolu_017T3prC235fRsL2YesFCaT5`</summary>

```text
docs/paper/sections/appendix.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "a0c76b47-3ec5-47d7-a99f-ef1fb7680cf8",
  "tool_use_result": {
    "filenames": [
      "docs/paper/sections/appendix.tex"
    ],
    "durationMs": 29,
    "numFiles": 1,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 32_

<details open><summary>🔧 Tool call — Bash · `toolu_011uUV7MHGhA6xQ5urTz7JMS`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/e41b22b4-8852-4330-9d93-534a6630d550/tool-results/mcp-agent-ml-research-read_registry-1779466359990.txt | python3 -c \"\nimport json, sys\ndata = json.loads(json.loads(sys.stdin.read())['result'])\nexps = data['data']['experiments']\n# Get plan010_nli_large_ablation full details\nexp = exps.get('plan010_nli_large_ablation', {})\nfor k, v in exp.items():\n    if v is not None and v != '' and v != {}:\n        print(f'{k}: {v}')\n\"",
  "description": "Get plan010_nli_large_ablation full details"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "99b2938d-44b3-4261-a50c-d4f83f248753",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KnwCY3Ui1jwDkbixFhKLi9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6092,
      "cache_read_input_tokens": 35842,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6092
      },
      "output_tokens": 58,
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

_source line 33 · 2026-05-22T16:14:42.256Z_

<details><summary>↩ Tool result · `toolu_011uUV7MHGhA6xQ5urTz7JMS`</summary>

```text
status: DONE
conclusion: success
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "c92ead25-8dfa-45d2-ae76-fa1675d5d48a",
  "tool_use_result": {
    "stdout": "status: DONE\nconclusion: success",
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

_source line 34_

<details open><summary>🔧 Tool call — Read · `toolu_01YK1bAUi4wqUTMSZR7ehh16`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "f52bd2f4-9c58-4de9-a110-a71880884e9a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018XLoE7RXk9das9jFGqLy7d",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 449,
      "cache_read_input_tokens": 41934,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 449
      },
      "output_tokens": 68,
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

_source line 35 · 2026-05-22T16:14:45.113Z_

<details><summary>↩ Tool result · `toolu_01YK1bAUi4wqUTMSZR7ehh16`</summary>

```text
1	\section{Training Hyperparameters}
2	\label{sec:hyperparams}
3	
4	Table~\ref{tab:hyperparams} lists the hyperparameters for all training configurations. All methods use LoRA with rank $r{=}64$ and $\alpha{=}128$ applied to all linear projections (attention and feed-forward). SFT and RSFT share the same optimizer settings; RSFT differs only in data construction (top-1 CED-selected outputs from $N{=}8$ candidates). GRPO and DPO use lower learning rates to stabilize post-SFT optimization.
5	
6	\begin{table*}[t]
7	\centering
8	\caption{Training hyperparameters for all optimization paradigms. All experiments use Qwen3-4B as the base model with LoRA adaptation. A dash indicates that the parameter is not applicable to the given method.}
9	\label{tab:hyperparams}
10	\small
11	\begin{tabular}{lccccc}
12	\toprule
13	\textbf{Parameter} & \textbf{SFT} & \textbf{RSFT} & \textbf{GRPO QLoRA} & \textbf{GRPO bf16} & \textbf{DPO} \\
14	\midrule
15	Base model & Qwen3-4B & Qwen3-4B & Qwen3-4B & Qwen3-4B & Qwen3-4B \\
16	LoRA rank $r$ & 64 & 64 & 64 & 64 & 64 \\
17	LoRA $\alpha$ & 128 & 128 & 128 & 128 & 128 \\
18	Learning rate & 2e-5 & 2e-5 & 5e-6 & 5e-6 & 5e-7 \\
19	Batch size (effective) & 16 & 16 & 4 & 8 & 4 \\
20	Epochs & 3 & 3 & -- & -- & 1, 3\textsuperscript{$\star$} \\
21	Max steps & -- & -- & 100 & 100 & -- \\
22	Gradient accumulation & 4 & 4 & 16 & 4 & 4 \\
23	Max new tokens & 1024 & 1024 & 1024 & 1024 & 1024 \\
24	Quantization & -- & -- & NF4 4-bit & bf16 & bf16 \\
25	Group size $G$ & -- & -- & 4 & 8 & -- \\
26	KL coefficient & -- & -- & 0.01 & 0.01 & -- \\
27	$\beta$ (DPO) & -- & -- & -- & -- & 0.1 \\
28	Candidates $N$ & -- & 8 & -- & -- & 8 \\
29	Top-$k$ selection & -- & 1 & -- & -- & -- \\
30	Training samples & 3,053 & 2,718 & 3,053 & 3,053 & 3,053 \\
31	Scoring function & -- & CED & CED & CED & CED \\
32	\bottomrule
33	\end{tabular}
34	\vspace{1mm}
35	{\raggedright\footnotesize \textsuperscript{$\star$}DPO is trained for both 1 and 3 epochs to observe temporal dynamics of the evidence-extraction trade-off (Section~\ref{sec:spectrum}).\par}
36	\end{table*}
37	
38	
39	\section{Full Ablation Results}
40	\label{sec:ablation_full}
41	
42	Table~\ref{tab:ablation_full} reports the complete RSFT ablation across scoring functions, top-$k$ values, and random seeds. RSFT CED $k{=}1$ achieves a four-seed mean Ign-F1 of 44.66 (standard deviation 0.49), confirming robust improvement over the SFT s42 baseline (39.74). The three-seed mean reported in Table~\ref{tab:main} (44.82, seeds 42/43/44) is slightly higher because it excludes the lowest seed (s45: 44.16). Random selection RSFT $k{=}1$ (41.14 Ign-F1), which samples from the same candidate pool without CED scoring, improves only +1.40pp over SFT s42 versus +4.92pp for CED RSFT, confirming that CED scoring precision drives the majority of the RSFT gain. Increasing $k$ to 3 slightly degrades performance (43.64 Ign-F1), consistent with the intuition that stricter selection yields higher-quality training data. The flat-NLI scoring variant produces comparable Rel-F1 (mean 45.61 vs.\ 45.63 for CED, a difference of 0.02pp). Both CED and flat-NLI improve substantially over the SFT baseline while maintaining or improving Evi-F1, confirming that the RSFT gains are driven by quality-based data selection rather than by the specific contrastive formulation.
43	
44	\paragraph{NLI scoring comparison.} Across all available seeds, CED RSFT achieves mean Rel-F1 of 45.63 (seeds 42, 43, 44, 45: range 45.14--46.21), and flat-NLI RSFT achieves mean Rel-F1 of 45.61 (seeds 42, 43: range 45.35--45.86). The 0.02pp difference suggests comparable performance: CED's contrastive design does not substantially outperform simpler NLI scoring for RSFT data selection. We adopt CED as the default because its contrastive formulation produces per-triple discrimination scores that support interpretable error analysis.
45	
46	\paragraph{Top-$k$ selection.} Best-of-8 ($k{=}1$) yields mean Ign-F1 44.66 and Rel-F1 45.63, while top-3-of-8 ($k{=}3$) produces 43.64 and 44.54. The selected training data confirms the quality gap: $k{=}1$ data has mean extraction F1 of 61.57 and mean CED of 0.6683, versus 57.61 and 0.6205 for $k{=}3$. Despite $k{=}3$ providing 2.96$\times$ more training examples, the additional lower-ranked samples introduce noise that degrades final performance.
47	
48	\paragraph{NLI scorer capacity.} CED filtering is robust to NLI model capacity: replacing the default scorer (DeBERTa-v3-base, 86M parameters) with DeBERTa-v3-large (304M) yields only +1.10pp Ign-F1 (45.33 vs.\ 44.23, s42), a difference within the v3-base seed noise of 0.88pp (s42: 44.23, s44: 45.11). Other metrics confirm the pattern: Rel-F1 improves by +1.19pp (46.36 vs.\ 45.17), Evi-F1 by +0.20pp (81.94 vs.\ 81.74), while EDCR shifts by $-$0.39pp (0.6530 vs.\ 0.6569)---the inconsistent direction across metrics rules out systematic improvement from a larger scorer. This insensitivity supports v3-base as a cost-effective default, as a 3.5$\times$ larger scorer does not materially improve CED-based data selection.
49	
50	\begin{table}[t]
51	\centering
52	\caption{Full RSFT ablation on DocRED dev set (Qwen3-4B). CED and flat-NLI denote the scoring function used for candidate selection. Best Ign-F1 among evidence-generating methods in \textbf{bold}.}
53	\label{tab:ablation_full}
54	\small
55	\resizebox{\columnwidth}{!}{%
56	\begin{tabular}{lcccc}
57	\toprule
58	\textbf{Configuration} & \textbf{Ign-F1} & \textbf{Rel-F1} & \textbf{Evi-F1} & \textbf{EDCR} \\
59	\midrule
60	SFT baseline (s42) & 39.74 & 40.49 & 79.86 & 0.6982 \\
61	SFT no-evidence & \textbf{47.21} & 48.76 & -- & -- \\
62	\midrule
63	RSFT random $k{=}1$ & 41.14 & 41.98 & 79.64 & 0.6971 \\
64	\midrule
65	RSFT CED $k{=}1$ (s42) & 44.23 & 45.17 & 81.74 & 0.6569 \\
66	RSFT CED $k{=}1$ (s43) & 45.12 & 46.01 & 80.63 & 0.6542 \\
67	RSFT CED $k{=}1$ (s44) & 45.11 & 46.21 & 80.50 & 0.6350 \\
68	RSFT CED $k{=}1$ (s45) & 44.16 & 45.14 & 81.74 & 0.6550 \\
69	RSFT CED $k{=}1$ (mean) & 44.66 & 45.63 & 81.15 & 0.6503 \\
70	\midrule
71	RSFT CED $k{=}3$ & 43.64 & 44.54 & 80.88 & 0.6635 \\
72	\midrule
73	RSFT flat-NLI (s42) & -- & 45.35 & 80.43 & 0.6431 \\
74	RSFT flat-NLI (s43) & -- & 45.86 & 81.58 & 0.6505 \\
75	RSFT flat-NLI (mean) & -- & 45.61 & 81.01 & 0.6468 \\
76	\midrule
77	RSFT CED $k{=}1$ v3-large (s42) & 45.33 & 46.36 & 81.94 & 0.6530 \\
78	\bottomrule
79	\end{tabular}%
80	}
81	\end{table}
82	
83	
84	\section{Scaling Details}
85	\label{sec:scaling_details}
86	
87	Table~\ref{tab:cross_detail} supplements Table~\ref{tab:scaling} in the main text with per-scale Rel-F1 and Evi-F1 breakdowns. At 1.7B, RSFT improves Rel-F1 from 45.86 to 52.81 (+6.95, multi-seed mean) while achieving Evi-F1 82.63 and EDCR 0.6217. The 4B model shows the same pattern: Rel-F1 increases from 44.39 to 45.80 (+1.41, three-seed mean). For 8B, RSFT brings Rel-F1 from 51.87 to 56.26 (three-seed mean) with Evi-F1 of 81.26 and EDCR 0.6235, confirming tight coupling between extraction and evidence at this scale. At 14B, the SFT baseline already achieves strong Rel-F1 (56.11) and Evi-F1 (82.92).
88	
89	\begin{table}[t]
90	\centering
91	\caption{Detailed Rel-F1 and Evi-F1 across model scales on DocRED dev set. SFT and RSFT columns show multi-seed means where available (Qwen3 1.7B/4B/8B: 3-seed; 14B: single seed; LLaMA SFT Rel-F1/Evi-F1: s42 only; LLaMA RSFT: 3-seed).}
92	\label{tab:cross_detail}
93	\small
94	\resizebox{\columnwidth}{!}{%
95	\begin{tabular}{lccccc}
96	\toprule
97	\textbf{Model} & \textbf{SFT Rel-F1} & \textbf{SFT Evi-F1} & \textbf{RSFT Rel-F1} & \textbf{RSFT Evi-F1} & \textbf{RSFT EDCR} \\
98	\midrule
99	Qwen3-1.7B & 45.86 & 82.85 & 52.81 & 82.63 & 0.6217 \\
100	Qwen3-4B & 44.39 & 79.61 & 45.80 & 80.96 & 0.6487 \\
101	Qwen3-8B & 51.87 & 82.94 & 56.26 & 81.26 & 0.6235 \\
102	Qwen3-14B & 56.11 & 82.92 & -- & -- & -- \\
103	LLaMA-3.1-8B & 55.14 & 81.51 & 57.75 & 82.84 & 0.5804 \\
104	\bottomrule
105	\end{tabular}%
106	}
107	\end{table}
108	
109	
110	\section{Controlled Evaluation Subset}
111	\label{sec:fair_subset}
112	
113	The 1.7B evidence tax comparison (\S\ref{sec:scaling}) is confounded by differential truncation rates. At \texttt{max\_new\_tokens}$=$1024, the no-evidence model truncates 50.9\% of outputs (501/985 documents) versus 31.9\% (314/985) for the evidence model. To address this, we adopt a matched@2048 fair evaluation: both configurations are evaluated at \texttt{max\_new\_tokens}$=$2048, and the tax is computed on the intersection of documents where both produce format-compliant output. This yields 971/985 fair-subset documents, with a tax of $-$5.63pp (s42), confirming a genuine 1.7B evidence benefit. As additional validation, a stricter controlled subset at @1024 (excluding truncated or repetitive outputs; 442/985 documents) yields $-$6.2pp, with the stronger benefit attributable to the more aggressive filtering.
114	
115	Table~\ref{tab:mechanistic} provides a mechanistic breakdown across three scales (evaluated at @1024). Output duplication rate (fraction of documents containing $\geq$3 repeated triples or unique/total $< 0.5$) declines monotonically with scale for both training configurations, but the gap between no-evidence and with-evidence models narrows from 27.5pp at 1.7B to 3.7pp at 8B. This pattern supports the implicit regularization hypothesis: evidence generation forces smaller models to attend to supporting context, reducing degenerate repetition. At 4B, duplication is already moderate (31.1\% with evidence), so the regularization benefit diminishes; under matched@2048 evaluation, the 4B training-time tax is approximately neutral (+0.25$\pm$0.47pp, three-seed mean). The truncation asymmetry reverses across scales: at 1.7B the no-evidence model truncates 19pp more often; at 8B the evidence model truncates 9pp more often due to the longer output format.
116	
117	\begin{table}[t]
118	\centering
119	\caption{Mechanistic breakdown of output quality across scales. Duplication rate: fraction of documents with degenerate outputs. Truncation $\Delta$: no-evidence rate minus with-evidence rate (positive means no-evidence truncates more).}
120	\label{tab:mechanistic}
121	\small
122	\begin{tabular}{lccccc}
123	\toprule
124	& \multicolumn{3}{c}{\textbf{Duplication Rate}} & \multicolumn{2}{c}{\textbf{Truncation}} \\
125	\cmidrule(lr){2-4} \cmidrule(lr){5-6}
126	\textbf{Scale} & \textbf{w/ evi} & \textbf{no-evi} & \textbf{Gap} & \textbf{$\Delta$} & \textbf{Pattern} \\
127	\midrule
128	1.7B & 33.0 & 60.5 & 27.5 & +19 & no-evi worse \\
129	4B & 31.1 & 43.2 & 12.1 & +2 & neutral \\
130	8B & 29.2 & 32.9 & 3.7 & $-$9 & evi worse \\
131	\bottomrule
132	\end{tabular}
133	\end{table}
134	
135	
136	\section{Training-Time Evidence Tax}
137	\label{sec:training_tax}
138	
139	The evidence tax can be measured in two ways. The \emph{training-time} tax compares separately trained models (SFT with evidence vs.\ SFT without evidence in the training output format). The \emph{inference-time} tax (reported in Table~\ref{tab:scaling}) evaluates the same RSFT model with and without evidence at inference time.
140	
141	Na\"ive comparisons at \texttt{max\_new\_tokens}$=$1024 are confounded by differential truncation rates (e.g., 50.9\% vs.\ 31.9\% at 1.7B). To control for this, we adopt a \emph{matched@2048 fair evaluation}: both configurations are evaluated at \texttt{max\_new\_tokens}$=$2048, and the tax is computed on the intersection of documents where both models produce format-compliant output. Table~\ref{tab:training_tax} reports the matched@2048 training-time tax across Qwen3 scales.
142	
143	The tax reveals a within-family capacity threshold: evidence generation benefits 1.7B ($-$5.63pp on 971/985 fair-subset documents) but is approximately neutral at $\geq$4B (+0.25$\pm$0.47pp at 4B across three seeds, +0.04pp at 8B, +0.03pp at 14B). At 1.7B, s42 is the strongest SFT seed (47.86 Ign-F1, +3.22pp above the three-seed mean of 44.64), so the benefit may be amplified relative to the population mean. LLaMA-3.1-8B SFT training-time tax is consistently negative but with high magnitude variance ($-$1.53 to $-$11.20pp, mean $-$5.19$\pm$5.25pp under matched@2048) and omitted from the table due to the s43 outlier (16.3\% no-evidence format failure inflates its tax); cross-architecture patterns are addressed in \S\ref{sec:generalization_full}.
144	
145	\begin{table}[t]
146	\centering
147	\caption{Training-time evidence tax under matched@2048 fair evaluation (DocRED dev Ign-F1). Both configurations evaluated at \texttt{max\_new\_tokens}$=$2048; tax computed on format-compliant intersection. Tax $=$ no-evidence $-$ with-evidence; positive $=$ cost.}
148	\label{tab:training_tax}
149	\small
150	\begin{tabular}{lcccc}
151	\toprule
152	\textbf{Model} & \textbf{Fair w/ evi} & \textbf{Fair no-evi} & \textbf{Evi Tax} & \textbf{Subset} \\
153	\midrule
154	Qwen3-1.7B & 48.38 & 42.75 & $-$5.63 & 971 \\
155	Qwen3-4B & -- & -- & +0.25{\scriptsize$\pm$0.47}$^{(3)}$ & $\geq$982 \\
156	Qwen3-8B & 50.15 & 50.19 & +0.04 & 984 \\
157	Qwen3-14B & 55.07 & 55.10 & +0.03 & 985$^\dagger$ \\
158	\bottomrule
159	\end{tabular}
160	\vspace{-2mm}
161	{\raggedright\footnotesize 1.7B and 8B are s42; 4B reports three-seed mean $\pm$ std (per-seed range: $-$0.19 to +0.73pp); 14B evaluated at @1024 with 0\% truncation for both configurations ($^\dagger$fair subset equals full dev set). Subset: documents in format-compliant intersection out of 985.\par}
162	\end{table}
163	
164	
165	\section{Why RSFT Avoids Decoupling}
166	\label{sec:rsft_theory}
167	
168	The structural difference between selection and optimization explains why RSFT does not exhibit the decoupling observed in gradient-based methods. GRPO and DPO update model parameters through gradients that optimize a reward signal. When two sub-tasks (extraction and evidence) compete for gradient capacity, the optimizer can discover and exploit the trade-off between them, improving one at the expense of the other. RSFT operates differently: it selects complete outputs and trains on them with standard supervised loss. Because the selection is discrete (accept or reject a full response), there is no gradient pathway through which the model can learn to sacrifice extraction for evidence quality. Only outputs where both extraction and evidence are jointly strong survive the CED filter. This property is not specific to RSFT's design but is a structural consequence of discrete selection over complete outputs: any selection-based method that filters on a joint quality criterion will inherit the same coupling guarantee. The implication for practitioners is direct: when optimizing for multiple coupled generation objectives, selection-based methods preserve inter-objective balance that gradient-based methods disrupt.
169	
170	
171	\section{Decoupling Spectrum Visualization}
172	\label{sec:spectrum_viz}
173	
174	\begin{figure}[t]
175	\centering
176	\includegraphics[width=\columnwidth]{fig_spectrum.pdf}
177	\caption{Decoupling spectrum visualization. Each method is plotted by Rel-F1 (x-axis) and Evi-F1 (y-axis). Arrows indicate training progression for DPO (1ep$\to$3ep) and GRPO bf16 trajectory. Ideal methods occupy the upper-right quadrant; decoupled methods drift toward the upper-left.}
178	\label{fig:spectrum}
179	\end{figure}
180	
181	
182	\section{Evidence Tax Visualization}
183	\label{sec:scaling_viz}
184	
185	\begin{figure}[t]
186	\centering
187	\includegraphics[width=\columnwidth]{fig_scaling.pdf}
188	\caption{Evidence tax across model scales. Bar heights show Ign-F1 for each training configuration. The gap between no-evidence and SFT bars reverses direction between 1.7B and 4B, revealing the scale-dependent nature of the evidence tax. RSFT consistently narrows the gap toward the no-evidence upper bound.}
189	\label{fig:scaling}
190	\end{figure}
191	
192	
193	\section{Full Generalization Results}
194	\label{sec:generalization_full}
195	
196	\paragraph{Cross-family transfer.}
197	LLaMA-3.1-8B confirms the scaling patterns observed with Qwen3. Its SFT baseline achieves a three-seed mean of 51.09 Ign-F1 (std 2.92pp; s42: 53.84, s43: 51.42, s44: 48.02). Under matched@2048 fair evaluation, the training-time tax is consistently negative across all three seeds (s42: $-$1.53, s43: $-$11.20, s44: $-$2.83; mean $-$5.19$\pm$5.25pp), indicating that evidence generation consistently benefits LLaMA-3.1-8B. This contrasts with Qwen3-8B's approximately neutral tax (+0.04pp), suggesting that the evidence tax may be architecture-dependent at the 8B scale; however, the high magnitude variance (driven by s43, whose no-evidence configuration has a 16.3\% format failure rate that inflates the tax estimate) precludes precise quantification. RSFT CED improves LLaMA to a three-seed mean of 56.54 Ign-F1 (std 0.64pp; s42: 57.14, s43: 56.62, s44: 55.87), a +5.45 point gain over SFT mean (51.09), with 4.6$\times$ variance compression (2.92pp $\to$ 0.64pp), consistent with the pattern at the 8B scale (Qwen3-8B: +4.33, 17$\times$ compression).
198	
199	\paragraph{Cross-dataset robustness.}
200	On Re-DocRED~\citep{tan2022redocred}, the SFT baseline achieves 36.59 Ign-F1 (Evi-F1 81.70, EDCR 0.6674). RSFT CED improves this to 41.45 Ign-F1 (Evi-F1 81.82, EDCR 0.6210), a +4.86pp gain that closely matches the +5.08pp improvement on DocRED (RSFT three-seed mean minus SFT s42). This consistency across datasets with different annotation protocols confirms that RSFT's benefit generalizes beyond training-set-specific artifacts. Evidence quality remains stable across datasets (Evi-F1 81.82 vs.\ 81.15 on DocRED), and the EDCR reduction ($-0.046$) mirrors the DocRED pattern, further supporting the robustness of CED-based selection.
201	
202	\paragraph{Re-DocRED test set evaluation.}
203	Table~\ref{tab:test_results} reports SFT and RSFT performance on the Re-DocRED test set. We observe a consistent performance gap between dev and test sets, with test Ign-F1 approximately 20 percentage points lower (RSFT: 1.7B 51.2$\to$29.3, 4B 44.8$\to$25.0, 8B 54.5$\to$33.5, 14B 58.9$\to$38.5, LLaMA-8B 56.5$\to$36.0; SFT 1.7B: 44.6$\to$25.8). This gap is attributable to annotation density: the test set contains 34.7 gold triples per document versus 12.3 in the dev set (a 2.82$\times$ ratio), imposing a harder recall requirement. The gap magnitude is stable across scales and architectures (range: 18.9--21.9pp), and model ranking is perfectly preserved (Spearman $\rho{=}1.0$), indicating that the absolute drop reflects the test annotation scheme rather than a model-specific deficiency. At 14B, the RSFT advantage observed on dev (+3.79pp) reverses on test ($\Delta{=}{-}0.37$pp); we note that the SFT model's 50.6\% truncation rate implies longer outputs that generate more candidate triples to match the test set's dense annotation scheme.
204	
205	\begin{table}[t]
206	\centering
207	\caption{SFT and RSFT performance on Re-DocRED test set (Ign-F1 \%). Dev Ign-F1 (RSFT) from Table~\ref{tab:scaling}. All test results use s42.}
208	\label{tab:test_results}
209	\small
210	\resizebox{\columnwidth}{!}{%
211	\begin{tabular}{lccccccc}
212	\toprule
213	\textbf{Model} & \textbf{Dev} & \textbf{SFT} & \textbf{RSFT} & \textbf{$\Delta$} & \textbf{Tr. SFT} & \textbf{Tr. RSFT} & \textbf{Evi-F1} \\
214	\midrule
215	Qwen3-1.7B & 51.19 & 25.79 & 29.33 & +3.54 & 81.8 & 73.8 & 23.20 \\
216	Qwen3-4B & 44.82$^\dagger$ & 22.32 & 25.01 & +2.69 & 64.6 & 42.8 & 18.38 \\
217	Qwen3-8B & 54.52 & 31.06 & 33.53 & +2.47 & 82.0 & 1.8 & 25.26 \\
218	Qwen3-14B & 58.86 & 38.86 & 38.49 & $-$0.37 & 50.6 & 13.4 & 26.88 \\
219	LLaMA-3.1-8B & 56.54 & 34.20 & 35.99 & +1.79 & 65.4 & 56.6 & 25.09 \\
220	\bottomrule
221	\end{tabular}%
222	}
223	\vspace{-2mm}
224	{\raggedright\footnotesize $^\dagger$4B dev Ign-F1 is three-seed mean from original checkpoint; test results use retrained checkpoint (original lost to server storage failure). $\Delta$: RSFT $-$ SFT. Evi-F1: RSFT joint (DREEAM protocol). Tr.: truncation rate (\%). Dev is RSFT three-seed mean from Table~\ref{tab:scaling}.\par}
225	\end{table}
226	
227	\paragraph{Test-set evidence tax.}
228	Table~\ref{tab:test_tax} reports the evidence tax on the Re-DocRED test set, comparing SFT models trained with and without evidence in the output format. Test-set evaluation confirms the directional pattern observed on development data across all five model configurations: the tax is negative (beneficial) at 1.7B ($-$4.86pp) and LLaMA-8B ($-$4.94pp), and near-neutral at mid-scales ($-$0.13pp at 4B, $-$0.32pp at 14B). The 8B test tax ($-$1.71pp) shows slight variation from its near-neutral dev counterpart (+0.04pp), though both remain modest relative to the 1.7B and LLaMA benefits.
229	
230	\begin{table}[t]
231	\centering
232	\caption{Evidence tax on Re-DocRED test set (Ign-F1 \%). Tax $=$ no-evi $-$ with-evi; negative $=$ benefit. All results use s42. Dev tax from Table~\ref{tab:training_tax}.}
233	\label{tab:test_tax}
234	\small
235	\resizebox{\columnwidth}{!}{%
236	\begin{tabular}{lcccc}
237	\toprule
238	\textbf{Model} & \textbf{With-evi} & \textbf{No-evi} & \textbf{Test Tax} & \textbf{Dev Tax} \\
239	\midrule
240	Qwen3-1.7B & 25.79 & 20.93 & $-$4.86 & $-$5.63 \\
241	Qwen3-4B & 22.32 & 22.19 & $-$0.13 & +0.25 \\
242	Qwen3-8B & 31.06 & 29.35 & $-$1.71 & +0.04 \\
243	Qwen3-14B & 38.86 & 38.54 & $-$0.32 & +0.03 \\
244	LLaMA-3.1-8B & 34.20 & 29.26 & $-$4.94 & $-$5.19 \\
245	\bottomrule
246	\end{tabular}%
247	}
248	\end{table}
249	
250	\paragraph{Comparison to supervised methods.}
251	Table~\ref{tab:encoder_comparison} directly compares encoder-based methods with our LLM-based approach. Encoder methods achieve substantially higher extraction performance (Rel-F1 63--65 vs.\ our 45--56), reflecting decades of architecture-specific optimization for the classification formulation. However, their evidence identification operates as binary sentence classification, producing Evi-F1 of 52--56 under a joint evaluation protocol. Our TP-only Evi-F1 exceeds 80\%, indicating that when the model correctly identifies a triple, it produces higher-quality evidence than encoder methods. The joint Evi-F1 gap (36.1 vs.\ 54.15) is driven primarily by extraction performance rather than evidence quality: false-positive and false-negative triples dilute the denominator. Closing this gap requires improving extraction capability of LLM-based methods, an orthogonal direction to the evidence faithfulness problem we address.
252	
253	\begin{table}[t]
254	\centering
255	\caption{Comparison with encoder-based methods on DocRED dev set. Encoder methods use RoBERTa-large; LLM methods use Qwen3. Evi-F1 for encoder methods uses joint evaluation (all triples in denominator); our joint Evi-F1 follows the same protocol for fair comparison. TP-only Evi-F1 conditions on correctly predicted triples. Rel-F1 is reported in percentage for all methods.}
256	\label{tab:encoder_comparison}
257	\small
258	\resizebox{\columnwidth}{!}{%
259	\begin{tabular}{llcccc}
260	\toprule
261	\textbf{Method} & \textbf{Type} & \textbf{Ign-F1} & \textbf{Rel-F1} & \textbf{Evi-F1 (joint)} & \textbf{Evi-F1 (TP)} \\
262	\midrule
263	ATLOP & Encoder & 61.32 & 63.18 & -- & -- \\
264	EIDER & Encoder & 62.34 & 64.27 & 52.54 & -- \\
265	SAIS & Encoder & 62.23 & 65.17 & 55.84 & -- \\
266	DREEAM & Encoder & 61.71 & 63.49 & 54.15 & -- \\
267	\midrule
268	Ours (4B RSFT) & LLM & 44.82 & 45.80 & 36.1 & 80.96 \\
269	Ours (8B RSFT) & LLM & 54.52 & 56.26 & -- & 81.26 \\
270	Ours (14B RSFT) & LLM & 58.86 & 60.09 & 48.59 & 83.92 \\
271	\bottomrule
272	\end{tabular}%
273	}
274	\end{table}
275	
276	
277	\section{GRPO Training Dynamics}
278	\label{sec:grpo_dynamics}
279	
280	\begin{figure*}[t]
281	\centering
282	\includegraphics[width=\linewidth]{fig_grpo_dynamics.pdf}
283	\caption{Training dynamics of GRPO under different configurations. (a)~Relation F1 across checkpoints: G=4 QLoRA suffers catastrophic collapse at step~10, while G=8 bf16 remains stable. (b)~Evidence F1 stays intact for G=8 bf16, confirming the generation mechanism itself does not fail. (c)~Evidence-Decoupling Ratio (EDCR) reveals near-total decoupling in G=4 QLoRA (extraction collapses to Rel-F1 1.4), while G=8 bf16 maintains healthy ratios.}
284	\label{fig:grpo_dynamics}
285	\end{figure*}
286	
287	
288	\section{Error Analysis: SFT vs.\ RSFT}
289	\label{sec:error_analysis}
290	
291	Table~\ref{tab:error_analysis} decomposes the extraction improvements from RSFT into error categories across three scales. Three mechanisms drive the gains consistently:
292	
293	\paragraph{Truncation false negatives.} SFT models frequently hit the generation length limit, producing incomplete outputs that miss triples. RSFT training on compact, high-quality outputs reduces this truncation rate. The effect is strongest at 1.7B ($-841$ truncation FN, $-22$\%), where the SFT model's output length is least controlled.
294	
295	\paragraph{Hallucinated false positives.} CED-based filtering removes training examples with unfaithful predictions, reducing the rate of hallucinated triples at inference. LLaMA benefits most ($-593$ hallucinated FP, $-11.8$\%), suggesting cross-architecture variation in hallucination susceptibility.
296	
297	\paragraph{Duplicate predictions.} RSFT training data, selected for quality, contains fewer repetitive patterns. This propagates to inference, reducing duplicate triples by $11$--$20$\% across scales, with 1.7B showing the largest reduction ($-20.2$\%).
298	
299	\paragraph{Evidence quality unchanged.} Despite substantial extraction improvements, evidence exact-match F1 changes by less than 0.4pp at every scale. RSFT selects for joint extraction-evidence quality, but the evidence signal in CED scoring does not translate into measurable evidence improvement. This suggests that evidence grounding requires targeted optimization (e.g., evidence-specific rewards in RL) rather than data selection alone.
300	
301	\paragraph{Residual difficulty.} The proportion of ``other'' false negatives (triples missed for reasons beyond truncation or formatting) increases by 13--15\% in relative terms after RSFT. As easy errors (truncation, duplication) are eliminated, the remaining error distribution shifts toward harder cases: cross-sentence reasoning, implicit relations, and long-tail entity pairs. The relation types with the largest RSFT gains (participant, conflict, league, screenwriter, operator, contains\_administrative\_territory) involve cross-sentence reasoning or long-tail entities, consistent with RSFT's selection pressure toward diverse, high-quality outputs.
302	
303	\begin{table}[t]
304	\centering
305	\caption{Error pattern changes from SFT to RSFT across scales. $\Delta$\% shows relative change. Truncation FN, hallucinated FP, and duplicates all decrease; evidence quality and residual FN difficulty are unchanged.}
306	\label{tab:error_analysis}
307	\small
308	\resizebox{\columnwidth}{!}{%
309	\begin{tabular}{llccc}
310	\toprule
311	\textbf{Error Category} & \textbf{Direction} & \textbf{1.7B} & \textbf{4B} & \textbf{8B / LLaMA} \\
312	\midrule
313	Truncation FN & $\downarrow$ & $-$22\% & $-$16\% & $-$18\% \\
314	Hallucinated FP & $\downarrow$ & $-$8\% & $-$6\% & $-$12\% \\
315	Duplicates & $\downarrow$ & $-$20\% & $-$11\% & $-$14\% \\
316	Evidence (exact) & $\approx$ & $<$0.4pp & $<$0.4pp & $<$0.4pp \\
317	FN: other & $\uparrow$ & +13\% & +15\% & +14\% \\
318	\bottomrule
319	\end{tabular}%
320	}
321	\end{table}
322	
323	
324	\section{Per-Relation EDCR Distribution}
325	\label{sec:edcr_per_relation}
326	
327	Computing EDCR for each of the 76 relation types with $\geq$5 evaluation samples (from the RSFT CED s42 model) reveals that per-relation EDCR correlates strongly with per-relation Rel-F1 ($\rho = -0.79$, $n = 76$, $p < 0.001$), confirming its utility as a difficulty indicator. Filtering to types with $\geq$5 predictions strengthens the correlation ($\rho = -0.85$, $n = 74$, $p < 0.001$). Per-relation EDCR is statistically independent of Evi-F1 ($\rho = -0.06$, $p = 0.58$), and Evi-F1 itself shows no association with Rel-F1 ($\rho = -0.01$, $p = 0.91$). These null correlations establish that evidence quality and extraction ability are fully decoupled across relation types. Extreme cases illustrate the diagnostic power: \texttt{date\_of\_birth} has EDCR $= 0.118$ (highly faithful, with extraction and evidence tightly coupled), while \texttt{head\_of\_government} reaches $0.956$ (highly decoupled). This per-relation analysis avoids the shared-component concern present in cross-method EDCR-vs-Rel-F1 correlation, providing independent validation of EDCR's diagnostic utility.
328	
329	\begin{figure}[t]
330	\centering
331	\includegraphics[width=\linewidth]{fig_edcr_relations.pdf}
332	\caption{Per-relation EDCR distribution across all 93 relation types observed in the development set (of 96 defined in DocRED). The correlation analysis in the text uses the 76 types with $\geq$5 samples for statistical reliability. Red bars indicate EDCR $\geq$ 0.70 (severe decoupling), green bars indicate EDCR $<$ 0.30 (healthy evidence grounding). Seven types exhibit EDCR = 1.0.}
333	\label{fig:edcr_relations}
334	\end{figure}
335	
336	
337	\section{Qualitative Analysis}
338	\label{sec:qualitative}
339	
340	We present representative examples illustrating three phenomena: evidence quality differences between SFT and RSFT, GRPO format gaming under catastrophic collapse, and per-relation EDCR diagnostics.
341	
342	\paragraph{Case 1: Evidence quality.}
343	Table~\ref{tab:case_evidence} compares evidence citations from SFT and RSFT on three documents. SFT tends to cite many sentences indiscriminately, including distractors unrelated to the target triple, while RSFT selects precisely the gold evidence sentences. For \emph{America's Sweetheart}, SFT cites 6 sentences (precision 0.17) whereas RSFT cites only the single correct sentence (precision 1.00). The pattern is consistent: SFT achieves evidence precision of 0.00--0.20 across these examples, while RSFT achieves 1.00 in all three cases.
344	
345	\begin{table}[t]
346	\centering
347	\caption{Evidence citation comparison between SFT and RSFT. Precision measures the fraction of cited sentences that match gold evidence.}
348	\label{tab:case_evidence}
349	\small
350	\resizebox{\columnwidth}{!}{%
351	\begin{tabular}{llccc}
352	\toprule
353	\textbf{Document} & \textbf{Triple} & \textbf{SFT Prec.} & \textbf{RSFT Prec.} & \textbf{SFT \#Cited} \\
354	\midrule
355	Oleg Tinkov & (Oleg Tinkov, country of citizenship, Russia) & 0.00 & 1.00 & 3 \\
356	America's Sweetheart & (record label, country, United States) & 0.17 & 1.00 & 6 \\
357	Jade (Mortal Kombat) & (Jade, present in work, Mortal Kombat) & 0.20 & 1.00 & 5 \\
358	\bottomrule
359	\end{tabular}%
360	}
361	\end{table}
362	
363	\paragraph{Case 2: GRPO format gaming.}
364	Under catastrophic collapse (GRPO QLoRA $G{=}4$), the model abandons the DocRED 96-type relation ontology and generates free-text relation labels. On the document \emph{Something to Believe In}, the model produces 35 predicted triples with relations such as ``is a'', ``honor'', and ``location'', none of which belong to the target ontology. All 35 predictions are incorrect. Similarly, for \emph{J\'{o}zef Pi\l{}sudski Monument}, 28 predictions use non-standard relations with 0 correct matches. The model retains the structural format of triple-with-evidence output but fills it with fabricated relation types. The model produces well-formed evidence for these non-existent relations.
365	
366	\paragraph{Case 3: EDCR diagnostics.}
367	Per-relation EDCR identifies specific relation types where extraction and evidence are misaligned. For \texttt{date\_of\_birth} (EDCR $= 0.118$), the model's evidence consistently matches gold annotations: both extraction and evidence point to the same biographical sentence. In contrast, \texttt{notable\_work} (EDCR $= 0.941$) exhibits severe decoupling: the model cites sentence [0] (a general introduction) instead of the gold evidence sentence [3] (which contains the actual work attribution). High-EDCR relations tend to involve indirect or multi-hop reasoning where surface-level context misleads the evidence generator.
368	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "b07e1913-f8d5-4f3d-bd05-93196135f96d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/appendix.tex",
      "content": "\\section{Training Hyperparameters}\n\\label{sec:hyperparams}\n\nTable~\\ref{tab:hyperparams} lists the hyperparameters for all training configurations. All methods use LoRA with rank $r{=}64$ and $\\alpha{=}128$ applied to all linear projections (attention and feed-forward). SFT and RSFT share the same optimizer settings; RSFT differs only in data construction (top-1 CED-selected outputs from $N{=}8$ candidates). GRPO and DPO use lower learning rates to stabilize post-SFT optimization.\n\n\\begin{table*}[t]\n\\centering\n\\caption{Training hyperparameters for all optimization paradigms. All experiments use Qwen3-4B as the base model with LoRA adaptation. A dash indicates that the parameter is not applicable to the given method.}\n\\label{tab:hyperparams}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Parameter} & \\textbf{SFT} & \\textbf{RSFT} & \\textbf{GRPO QLoRA} & \\textbf{GRPO bf16} & \\textbf{DPO} \\\\\n\\midrule\nBase model & Qwen3-4B & Qwen3-4B & Qwen3-4B & Qwen3-4B & Qwen3-4B \\\\\nLoRA rank $r$ & 64 & 64 & 64 & 64 & 64 \\\\\nLoRA $\\alpha$ & 128 & 128 & 128 & 128 & 128 \\\\\nLearning rate & 2e-5 & 2e-5 & 5e-6 & 5e-6 & 5e-7 \\\\\nBatch size (effective) & 16 & 16 & 4 & 8 & 4 \\\\\nEpochs & 3 & 3 & -- & -- & 1, 3\\textsuperscript{$\\star$} \\\\\nMax steps & -- & -- & 100 & 100 & -- \\\\\nGradient accumulation & 4 & 4 & 16 & 4 & 4 \\\\\nMax new tokens & 1024 & 1024 & 1024 & 1024 & 1024 \\\\\nQuantization & -- & -- & NF4 4-bit & bf16 & bf16 \\\\\nGroup size $G$ & -- & -- & 4 & 8 & -- \\\\\nKL coefficient & -- & -- & 0.01 & 0.01 & -- \\\\\n$\\beta$ (DPO) & -- & -- & -- & -- & 0.1 \\\\\nCandidates $N$ & -- & 8 & -- & -- & 8 \\\\\nTop-$k$ selection & -- & 1 & -- & -- & -- \\\\\nTraining samples & 3,053 & 2,718 & 3,053 & 3,053 & 3,053 \\\\\nScoring function & -- & CED & CED & CED & CED \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1mm}\n{\\raggedright\\footnotesize \\textsuperscript{$\\star$}DPO is trained for both 1 and 3 epochs to observe temporal dynamics of the evidence-extraction trade-off (Section~\\ref{sec:spectrum}).\\par}\n\\end{table*}\n\n\n\\section{Full Ablation Results}\n\\label{sec:ablation_full}\n\nTable~\\ref{tab:ablation_full} reports the complete RSFT ablation across scoring functions, top-$k$ values, and random seeds. RSFT CED $k{=}1$ achieves a four-seed mean Ign-F1 of 44.66 (standard deviation 0.49), confirming robust improvement over the SFT s42 baseline (39.74). The three-seed mean reported in Table~\\ref{tab:main} (44.82, seeds 42/43/44) is slightly higher because it excludes the lowest seed (s45: 44.16). Random selection RSFT $k{=}1$ (41.14 Ign-F1), which samples from the same candidate pool without CED scoring, improves only +1.40pp over SFT s42 versus +4.92pp for CED RSFT, confirming that CED scoring precision drives the majority of the RSFT gain. Increasing $k$ to 3 slightly degrades performance (43.64 Ign-F1), consistent with the intuition that stricter selection yields higher-quality training data. The flat-NLI scoring variant produces comparable Rel-F1 (mean 45.61 vs.\\ 45.63 for CED, a difference of 0.02pp). Both CED and flat-NLI improve substantially over the SFT baseline while maintaining or improving Evi-F1, confirming that the RSFT gains are driven by quality-based data selection rather than by the specific contrastive formulation.\n\n\\paragraph{NLI scoring comparison.} Across all available seeds, CED RSFT achieves mean Rel-F1 of 45.63 (seeds 42, 43, 44, 45: range 45.14--46.21), and flat-NLI RSFT achieves mean Rel-F1 of 45.61 (seeds 42, 43: range 45.35--45.86). The 0.02pp difference suggests comparable performance: CED's contrastive design does not substantially outperform simpler NLI scoring for RSFT data selection. We adopt CED as the default because its contrastive formulation produces per-triple discrimination scores that support interpretable error analysis.\n\n\\paragraph{Top-$k$ selection.} Best-of-8 ($k{=}1$) yields mean Ign-F1 44.66 and Rel-F1 45.63, while top-3-of-8 ($k{=}3$) produces 43.64 and 44.54. The selected training data confirms the quality gap: $k{=}1$ data has mean extraction F1 of 61.57 and mean CED of 0.6683, versus 57.61 and 0.6205 for $k{=}3$. Despite $k{=}3$ providing 2.96$\\times$ more training examples, the additional lower-ranked samples introduce noise that degrades final performance.\n\n\\paragraph{NLI scorer capacity.} CED filtering is robust to NLI model capacity: replacing the default scorer (DeBERTa-v3-base, 86M parameters) with DeBERTa-v3-large (304M) yields only +1.10pp Ign-F1 (45.33 vs.\\ 44.23, s42), a difference within the v3-base seed noise of 0.88pp (s42: 44.23, s44: 45.11). Other metrics confirm the pattern: Rel-F1 improves by +1.19pp (46.36 vs.\\ 45.17), Evi-F1 by +0.20pp (81.94 vs.\\ 81.74), while EDCR shifts by $-$0.39pp (0.6530 vs.\\ 0.6569)---the inconsistent direction across metrics rules out systematic improvement from a larger scorer. This insensitivity supports v3-base as a cost-effective default, as a 3.5$\\times$ larger scorer does not materially improve CED-based data selection.\n\n\\begin{table}[t]\n\\centering\n\\caption{Full RSFT ablation on DocRED dev set (Qwen3-4B). CED and flat-NLI denote the scoring function used for candidate selection. Best Ign-F1 among evidence-generating methods in \\textbf{bold}.}\n\\label{tab:ablation_full}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Configuration} & \\textbf{Ign-F1} & \\textbf{Rel-F1} & \\textbf{Evi-F1} & \\textbf{EDCR} \\\\\n\\midrule\nSFT baseline (s42) & 39.74 & 40.49 & 79.86 & 0.6982 \\\\\nSFT no-evidence & \\textbf{47.21} & 48.76 & -- & -- \\\\\n\\midrule\nRSFT random $k{=}1$ & 41.14 & 41.98 & 79.64 & 0.6971 \\\\\n\\midrule\nRSFT CED $k{=}1$ (s42) & 44.23 & 45.17 & 81.74 & 0.6569 \\\\\nRSFT CED $k{=}1$ (s43) & 45.12 & 46.01 & 80.63 & 0.6542 \\\\\nRSFT CED $k{=}1$ (s44) & 45.11 & 46.21 & 80.50 & 0.6350 \\\\\nRSFT CED $k{=}1$ (s45) & 44.16 & 45.14 & 81.74 & 0.6550 \\\\\nRSFT CED $k{=}1$ (mean) & 44.66 & 45.63 & 81.15 & 0.6503 \\\\\n\\midrule\nRSFT CED $k{=}3$ & 43.64 & 44.54 & 80.88 & 0.6635 \\\\\n\\midrule\nRSFT flat-NLI (s42) & -- & 45.35 & 80.43 & 0.6431 \\\\\nRSFT flat-NLI (s43) & -- & 45.86 & 81.58 & 0.6505 \\\\\nRSFT flat-NLI (mean) & -- & 45.61 & 81.01 & 0.6468 \\\\\n\\midrule\nRSFT CED $k{=}1$ v3-large (s42) & 45.33 & 46.36 & 81.94 & 0.6530 \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\n\\section{Scaling Details}\n\\label{sec:scaling_details}\n\nTable~\\ref{tab:cross_detail} supplements Table~\\ref{tab:scaling} in the main text with per-scale Rel-F1 and Evi-F1 breakdowns. At 1.7B, RSFT improves Rel-F1 from 45.86 to 52.81 (+6.95, multi-seed mean) while achieving Evi-F1 82.63 and EDCR 0.6217. The 4B model shows the same pattern: Rel-F1 increases from 44.39 to 45.80 (+1.41, three-seed mean). For 8B, RSFT brings Rel-F1 from 51.87 to 56.26 (three-seed mean) with Evi-F1 of 81.26 and EDCR 0.6235, confirming tight coupling between extraction and evidence at this scale. At 14B, the SFT baseline already achieves strong Rel-F1 (56.11) and Evi-F1 (82.92).\n\n\\begin{table}[t]\n\\centering\n\\caption{Detailed Rel-F1 and Evi-F1 across model scales on DocRED dev set. SFT and RSFT columns show multi-seed means where available (Qwen3 1.7B/4B/8B: 3-seed; 14B: single seed; LLaMA SFT Rel-F1/Evi-F1: s42 only; LLaMA RSFT: 3-seed).}\n\\label{tab:cross_detail}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Model} & \\textbf{SFT Rel-F1} & \\textbf{SFT Evi-F1} & \\textbf{RSFT Rel-F1} & \\textbf{RSFT Evi-F1} & \\textbf{RSFT EDCR} \\\\\n\\midrule\nQwen3-1.7B & 45.86 & 82.85 & 52.81 & 82.63 & 0.6217 \\\\\nQwen3-4B & 44.39 & 79.61 & 45.80 & 80.96 & 0.6487 \\\\\nQwen3-8B & 51.87 & 82.94 & 56.26 & 81.26 & 0.6235 \\\\\nQwen3-14B & 56.11 & 82.92 & -- & -- & -- \\\\\nLLaMA-3.1-8B & 55.14 & 81.51 & 57.75 & 82.84 & 0.5804 \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\n\\section{Controlled Evaluation Subset}\n\\label{sec:fair_subset}\n\nThe 1.7B evidence tax comparison (\\S\\ref{sec:scaling}) is confounded by differential truncation rates. At \\texttt{max\\_new\\_tokens}$=$1024, the no-evidence model truncates 50.9\\% of outputs (501/985 documents) versus 31.9\\% (314/985) for the evidence model. To address this, we adopt a matched@2048 fair evaluation: both configurations are evaluated at \\texttt{max\\_new\\_tokens}$=$2048, and the tax is computed on the intersection of documents where both produce format-compliant output. This yields 971/985 fair-subset documents, with a tax of $-$5.63pp (s42), confirming a genuine 1.7B evidence benefit. As additional validation, a stricter controlled subset at @1024 (excluding truncated or repetitive outputs; 442/985 documents) yields $-$6.2pp, with the stronger benefit attributable to the more aggressive filtering.\n\nTable~\\ref{tab:mechanistic} provides a mechanistic breakdown across three scales (evaluated at @1024). Output duplication rate (fraction of documents containing $\\geq$3 repeated triples or unique/total $< 0.5$) declines monotonically with scale for both training configurations, but the gap between no-evidence and with-evidence models narrows from 27.5pp at 1.7B to 3.7pp at 8B. This pattern supports the implicit regularization hypothesis: evidence generation forces smaller models to attend to supporting context, reducing degenerate repetition. At 4B, duplication is already moderate (31.1\\% with evidence), so the regularization benefit diminishes; under matched@2048 evaluation, the 4B training-time tax is approximately neutral (+0.25$\\pm$0.47pp, three-seed mean). The truncation asymmetry reverses across scales: at 1.7B the no-evidence model truncates 19pp more often; at 8B the evidence model truncates 9pp more often due to the longer output format.\n\n\\begin{table}[t]\n\\centering\n\\caption{Mechanistic breakdown of output quality across scales. Duplication rate: fraction of documents with degenerate outputs. Truncation $\\Delta$: no-evidence rate minus with-evidence rate (positive means no-evidence truncates more).}\n\\label{tab:mechanistic}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\n& \\multicolumn{3}{c}{\\textbf{Duplication Rate}} & \\multicolumn{2}{c}{\\textbf{Truncation}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-6}\n\\textbf{Scale} & \\textbf{w/ evi} & \\textbf{no-evi} & \\textbf{Gap} & \\textbf{$\\Delta$} & \\textbf{Pattern} \\\\\n\\midrule\n1.7B & 33.0 & 60.5 & 27.5 & +19 & no-evi worse \\\\\n4B & 31.1 & 43.2 & 12.1 & +2 & neutral \\\\\n8B & 29.2 & 32.9 & 3.7 & $-$9 & evi worse \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Training-Time Evidence Tax}\n\\label{sec:training_tax}\n\nThe evidence tax can be measured in two ways. The \\emph{training-time} tax compares separately trained models (SFT with evidence vs.\\ SFT without evidence in the training output format). The \\emph{inference-time} tax (reported in Table~\\ref{tab:scaling}) evaluates the same RSFT model with and without evidence at inference time.\n\nNa\\\"ive comparisons at \\texttt{max\\_new\\_tokens}$=$1024 are confounded by differential truncation rates (e.g., 50.9\\% vs.\\ 31.9\\% at 1.7B). To control for this, we adopt a \\emph{matched@2048 fair evaluation}: both configurations are evaluated at \\texttt{max\\_new\\_tokens}$=$2048, and the tax is computed on the intersection of documents where both models produce format-compliant output. Table~\\ref{tab:training_tax} reports the matched@2048 training-time tax across Qwen3 scales.\n\nThe tax reveals a within-family capacity threshold: evidence generation benefits 1.7B ($-$5.63pp on 971/985 fair-subset documents) but is approximately neutral at $\\geq$4B (+0.25$\\pm$0.47pp at 4B across three seeds, +0.04pp at 8B, +0.03pp at 14B). At 1.7B, s42 is the strongest SFT seed (47.86 Ign-F1, +3.22pp above the three-seed mean of 44.64), so the benefit may be amplified relative to the population mean. LLaMA-3.1-8B SFT training-time tax is consistently negative but with high magnitude variance ($-$1.53 to $-$11.20pp, mean $-$5.19$\\pm$5.25pp under matched@2048) and omitted from the table due to the s43 outlier (16.3\\% no-evidence format failure inflates its tax); cross-architecture patterns are addressed in \\S\\ref{sec:generalization_full}.\n\n\\begin{table}[t]\n\\centering\n\\caption{Training-time evidence tax under matched@2048 fair evaluation (DocRED dev Ign-F1). Both configurations evaluated at \\texttt{max\\_new\\_tokens}$=$2048; tax computed on format-compliant intersection. Tax $=$ no-evidence $-$ with-evidence; positive $=$ cost.}\n\\label{tab:training_tax}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Fair w/ evi} & \\textbf{Fair no-evi} & \\textbf{Evi Tax} & \\textbf{Subset} \\\\\n\\midrule\nQwen3-1.7B & 48.38 & 42.75 & $-$5.63 & 971 \\\\\nQwen3-4B & -- & -- & +0.25{\\scriptsize$\\pm$0.47}$^{(3)}$ & $\\geq$982 \\\\\nQwen3-8B & 50.15 & 50.19 & +0.04 & 984 \\\\\nQwen3-14B & 55.07 & 55.10 & +0.03 & 985$^\\dagger$ \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{-2mm}\n{\\raggedright\\footnotesize 1.7B and 8B are s42; 4B reports three-seed mean $\\pm$ std (per-seed range: $-$0.19 to +0.73pp); 14B evaluated at @1024 with 0\\% truncation for both configurations ($^\\dagger$fair subset equals full dev set). Subset: documents in format-compliant intersection out of 985.\\par}\n\\end{table}\n\n\n\\section{Why RSFT Avoids Decoupling}\n\\label{sec:rsft_theory}\n\nThe structural difference between selection and optimization explains why RSFT does not exhibit the decoupling observed in gradient-based methods. GRPO and DPO update model parameters through gradients that optimize a reward signal. When two sub-tasks (extraction and evidence) compete for gradient capacity, the optimizer can discover and exploit the trade-off between them, improving one at the expense of the other. RSFT operates differently: it selects complete outputs and trains on them with standard supervised loss. Because the selection is discrete (accept or reject a full response), there is no gradient pathway through which the model can learn to sacrifice extraction for evidence quality. Only outputs where both extraction and evidence are jointly strong survive the CED filter. This property is not specific to RSFT's design but is a structural consequence of discrete selection over complete outputs: any selection-based method that filters on a joint quality criterion will inherit the same coupling guarantee. The implication for practitioners is direct: when optimizing for multiple coupled generation objectives, selection-based methods preserve inter-objective balance that gradient-based methods disrupt.\n\n\n\\section{Decoupling Spectrum Visualization}\n\\label{sec:spectrum_viz}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_spectrum.pdf}\n\\caption{Decoupling spectrum visualization. Each method is plotted by Rel-F1 (x-axis) and Evi-F1 (y-axis). Arrows indicate training progression for DPO (1ep$\\to$3ep) and GRPO bf16 trajectory. Ideal methods occupy the upper-right quadrant; decoupled methods drift toward the upper-left.}\n\\label{fig:spectrum}\n\\end{figure}\n\n\n\\section{Evidence Tax Visualization}\n\\label{sec:scaling_viz}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_scaling.pdf}\n\\caption{Evidence tax across model scales. Bar heights show Ign-F1 for each training configuration. The gap between no-evidence and SFT bars reverses direction between 1.7B and 4B, revealing the scale-dependent nature of the evidence tax. RSFT consistently narrows the gap toward the no-evidence upper bound.}\n\\label{fig:scaling}\n\\end{figure}\n\n\n\\section{Full Generalization Results}\n\\label{sec:generalization_full}\n\n\\paragraph{Cross-family transfer.}\nLLaMA-3.1-8B confirms the scaling patterns observed with Qwen3. Its SFT baseline achieves a three-seed mean of 51.09 Ign-F1 (std 2.92pp; s42: 53.84, s43: 51.42, s44: 48.02). Under matched@2048 fair evaluation, the training-time tax is consistently negative across all three seeds (s42: $-$1.53, s43: $-$11.20, s44: $-$2.83; mean $-$5.19$\\pm$5.25pp), indicating that evidence generation consistently benefits LLaMA-3.1-8B. This contrasts with Qwen3-8B's approximately neutral tax (+0.04pp), suggesting that the evidence tax may be architecture-dependent at the 8B scale; however, the high magnitude variance (driven by s43, whose no-evidence configuration has a 16.3\\% format failure rate that inflates the tax estimate) precludes precise quantification. RSFT CED improves LLaMA to a three-seed mean of 56.54 Ign-F1 (std 0.64pp; s42: 57.14, s43: 56.62, s44: 55.87), a +5.45 point gain over SFT mean (51.09), with 4.6$\\times$ variance compression (2.92pp $\\to$ 0.64pp), consistent with the pattern at the 8B scale (Qwen3-8B: +4.33, 17$\\times$ compression).\n\n\\paragraph{Cross-dataset robustness.}\nOn Re-DocRED~\\citep{tan2022redocred}, the SFT baseline achieves 36.59 Ign-F1 (Evi-F1 81.70, EDCR 0.6674). RSFT CED improves this to 41.45 Ign-F1 (Evi-F1 81.82, EDCR 0.6210), a +4.86pp gain that closely matches the +5.08pp improvement on DocRED (RSFT three-seed mean minus SFT s42). This consistency across datasets with different annotation protocols confirms that RSFT's benefit generalizes beyond training-set-specific artifacts. Evidence quality remains stable across datasets (Evi-F1 81.82 vs.\\ 81.15 on DocRED), and the EDCR reduction ($-0.046$) mirrors the DocRED pattern, further supporting the robustness of CED-based selection.\n\n\\paragraph{Re-DocRED test set evaluation.}\nTable~\\ref{tab:test_results} reports SFT and RSFT performance on the Re-DocRED test set. We observe a consistent performance gap between dev and test sets, with test Ign-F1 approximately 20 percentage points lower (RSFT: 1.7B 51.2$\\to$29.3, 4B 44.8$\\to$25.0, 8B 54.5$\\to$33.5, 14B 58.9$\\to$38.5, LLaMA-8B 56.5$\\to$36.0; SFT 1.7B: 44.6$\\to$25.8). This gap is attributable to annotation density: the test set contains 34.7 gold triples per document versus 12.3 in the dev set (a 2.82$\\times$ ratio), imposing a harder recall requirement. The gap magnitude is stable across scales and architectures (range: 18.9--21.9pp), and model ranking is perfectly preserved (Spearman $\\rho{=}1.0$), indicating that the absolute drop reflects the test annotation scheme rather than a model-specific deficiency. At 14B, the RSFT advantage observed on dev (+3.79pp) reverses on test ($\\Delta{=}{-}0.37$pp); we note that the SFT model's 50.6\\% truncation rate implies longer outputs that generate more candidate triples to match the test set's dense annotation scheme.\n\n\\begin{table}[t]\n\\centering\n\\caption{SFT and RSFT performance on Re-DocRED test set (Ign-F1 \\%). Dev Ign-F1 (RSFT) from Table~\\ref{tab:scaling}. All test results use s42.}\n\\label{tab:test_results}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccccc}\n\\toprule\n\\textbf{Model} & \\textbf{Dev} & \\textbf{SFT} & \\textbf{RSFT} & \\textbf{$\\Delta$} & \\textbf{Tr. SFT} & \\textbf{Tr. RSFT} & \\textbf{Evi-F1} \\\\\n\\midrule\nQwen3-1.7B & 51.19 & 25.79 & 29.33 & +3.54 & 81.8 & 73.8 & 23.20 \\\\\nQwen3-4B & 44.82$^\\dagger$ & 22.32 & 25.01 & +2.69 & 64.6 & 42.8 & 18.38 \\\\\nQwen3-8B & 54.52 & 31.06 & 33.53 & +2.47 & 82.0 & 1.8 & 25.26 \\\\\nQwen3-14B & 58.86 & 38.86 & 38.49 & $-$0.37 & 50.6 & 13.4 & 26.88 \\\\\nLLaMA-3.1-8B & 56.54 & 34.20 & 35.99 & +1.79 & 65.4 & 56.6 & 25.09 \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\vspace{-2mm}\n{\\raggedright\\footnotesize $^\\dagger$4B dev Ign-F1 is three-seed mean from original checkpoint; test results use retrained checkpoint (original lost to server storage failure). $\\Delta$: RSFT $-$ SFT. Evi-F1: RSFT joint (DREEAM protocol). Tr.: truncation rate (\\%). Dev is RSFT three-seed mean from Table~\\ref{tab:scaling}.\\par}\n\\end{table}\n\n\\paragraph{Test-set evidence tax.}\nTable~\\ref{tab:test_tax} reports the evidence tax on the Re-DocRED test set, comparing SFT models trained with and without evidence in the output format. Test-set evaluation confirms the directional pattern observed on development data across all five model configurations: the tax is negative (beneficial) at 1.7B ($-$4.86pp) and LLaMA-8B ($-$4.94pp), and near-neutral at mid-scales ($-$0.13pp at 4B, $-$0.32pp at 14B). The 8B test tax ($-$1.71pp) shows slight variation from its near-neutral dev counterpart (+0.04pp), though both remain modest relative to the 1.7B and LLaMA benefits.\n\n\\begin{table}[t]\n\\centering\n\\caption{Evidence tax on Re-DocRED test set (Ign-F1 \\%). Tax $=$ no-evi $-$ with-evi; negative $=$ benefit. All results use s42. Dev tax from Table~\\ref{tab:training_tax}.}\n\\label{tab:test_tax}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Model} & \\textbf{With-evi} & \\textbf{No-evi} & \\textbf{Test Tax} & \\textbf{Dev Tax} \\\\\n\\midrule\nQwen3-1.7B & 25.79 & 20.93 & $-$4.86 & $-$5.63 \\\\\nQwen3-4B & 22.32 & 22.19 & $-$0.13 & +0.25 \\\\\nQwen3-8B & 31.06 & 29.35 & $-$1.71 & +0.04 \\\\\nQwen3-14B & 38.86 & 38.54 & $-$0.32 & +0.03 \\\\\nLLaMA-3.1-8B & 34.20 & 29.26 & $-$4.94 & $-$5.19 \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\\paragraph{Comparison to supervised methods.}\nTable~\\ref{tab:encoder_comparison} directly compares encoder-based methods with our LLM-based approach. Encoder methods achieve substantially higher extraction performance (Rel-F1 63--65 vs.\\ our 45--56), reflecting decades of architecture-specific optimization for the classification formulation. However, their evidence identification operates as binary sentence classification, producing Evi-F1 of 52--56 under a joint evaluation protocol. Our TP-only Evi-F1 exceeds 80\\%, indicating that when the model correctly identifies a triple, it produces higher-quality evidence than encoder methods. The joint Evi-F1 gap (36.1 vs.\\ 54.15) is driven primarily by extraction performance rather than evidence quality: false-positive and false-negative triples dilute the denominator. Closing this gap requires improving extraction capability of LLM-based methods, an orthogonal direction to the evidence faithfulness problem we address.\n\n\\begin{table}[t]\n\\centering\n\\caption{Comparison with encoder-based methods on DocRED dev set. Encoder methods use RoBERTa-large; LLM methods use Qwen3. Evi-F1 for encoder methods uses joint evaluation (all triples in denominator); our joint Evi-F1 follows the same protocol for fair comparison. TP-only Evi-F1 conditions on correctly predicted triples. Rel-F1 is reported in percentage for all methods.}\n\\label{tab:encoder_comparison}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Method} & \\textbf{Type} & \\textbf{Ign-F1} & \\textbf{Rel-F1} & \\textbf{Evi-F1 (joint)} & \\textbf{Evi-F1 (TP)} \\\\\n\\midrule\nATLOP & Encoder & 61.32 & 63.18 & -- & -- \\\\\nEIDER & Encoder & 62.34 & 64.27 & 52.54 & -- \\\\\nSAIS & Encoder & 62.23 & 65.17 & 55.84 & -- \\\\\nDREEAM & Encoder & 61.71 & 63.49 & 54.15 & -- \\\\\n\\midrule\nOurs (4B RSFT) & LLM & 44.82 & 45.80 & 36.1 & 80.96 \\\\\nOurs (8B RSFT) & LLM & 54.52 & 56.26 & -- & 81.26 \\\\\nOurs (14B RSFT) & LLM & 58.86 & 60.09 & 48.59 & 83.92 \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\n\\section{GRPO Training Dynamics}\n\\label{sec:grpo_dynamics}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{fig_grpo_dynamics.pdf}\n\\caption{Training dynamics of GRPO under different configurations. (a)~Relation F1 across checkpoints: G=4 QLoRA suffers catastrophic collapse at step~10, while G=8 bf16 remains stable. (b)~Evidence F1 stays intact for G=8 bf16, confirming the generation mechanism itself does not fail. (c)~Evidence-Decoupling Ratio (EDCR) reveals near-total decoupling in G=4 QLoRA (extraction collapses to Rel-F1 1.4), while G=8 bf16 maintains healthy ratios.}\n\\label{fig:grpo_dynamics}\n\\end{figure*}\n\n\n\\section{Error Analysis: SFT vs.\\ RSFT}\n\\label{sec:error_analysis}\n\nTable~\\ref{tab:error_analysis} decomposes the extraction improvements from RSFT into error categories across three scales. Three mechanisms drive the gains consistently:\n\n\\paragraph{Truncation false negatives.} SFT models frequently hit the generation length limit, producing incomplete outputs that miss triples. RSFT training on compact, high-quality outputs reduces this truncation rate. The effect is strongest at 1.7B ($-841$ truncation FN, $-22$\\%), where the SFT model's output length is least controlled.\n\n\\paragraph{Hallucinated false positives.} CED-based filtering removes training examples with unfaithful predictions, reducing the rate of hallucinated triples at inference. LLaMA benefits most ($-593$ hallucinated FP, $-11.8$\\%), suggesting cross-architecture variation in hallucination susceptibility.\n\n\\paragraph{Duplicate predictions.} RSFT training data, selected for quality, contains fewer repetitive patterns. This propagates to inference, reducing duplicate triples by $11$--$20$\\% across scales, with 1.7B showing the largest reduction ($-20.2$\\%).\n\n\\paragraph{Evidence quality unchanged.} Despite substantial extraction improvements, evidence exact-match F1 changes by less than 0.4pp at every scale. RSFT selects for joint extraction-evidence quality, but the evidence signal in CED scoring does not translate into measurable evidence improvement. This suggests that evidence grounding requires targeted optimization (e.g., evidence-specific rewards in RL) rather than data selection alone.\n\n\\paragraph{Residual difficulty.} The proportion of ``other'' false negatives (triples missed for reasons beyond truncation or formatting) increases by 13--15\\% in relative terms after RSFT. As easy errors (truncation, duplication) are eliminated, the remaining error distribution shifts toward harder cases: cross-sentence reasoning, implicit relations, and long-tail entity pairs. The relation types with the largest RSFT gains (participant, conflict, league, screenwriter, operator, contains\\_administrative\\_territory) involve cross-sentence reasoning or long-tail entities, consistent with RSFT's selection pressure toward diverse, high-quality outputs.\n\n\\begin{table}[t]\n\\centering\n\\caption{Error pattern changes from SFT to RSFT across scales. $\\Delta$\\% shows relative change. Truncation FN, hallucinated FP, and duplicates all decrease; evidence quality and residual FN difficulty are unchanged.}\n\\label{tab:error_analysis}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Error Category} & \\textbf{Direction} & \\textbf{1.7B} & \\textbf{4B} & \\textbf{8B / LLaMA} \\\\\n\\midrule\nTruncation FN & $\\downarrow$ & $-$22\\% & $-$16\\% & $-$18\\% \\\\\nHallucinated FP & $\\downarrow$ & $-$8\\% & $-$6\\% & $-$12\\% \\\\\nDuplicates & $\\downarrow$ & $-$20\\% & $-$11\\% & $-$14\\% \\\\\nEvidence (exact) & $\\approx$ & $<$0.4pp & $<$0.4pp & $<$0.4pp \\\\\nFN: other & $\\uparrow$ & +13\\% & +15\\% & +14\\% \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\n\\section{Per-Relation EDCR Distribution}\n\\label{sec:edcr_per_relation}\n\nComputing EDCR for each of the 76 relation types with $\\geq$5 evaluation samples (from the RSFT CED s42 model) reveals that per-relation EDCR correlates strongly with per-relation Rel-F1 ($\\rho = -0.79$, $n = 76$, $p < 0.001$), confirming its utility as a difficulty indicator. Filtering to types with $\\geq$5 predictions strengthens the correlation ($\\rho = -0.85$, $n = 74$, $p < 0.001$). Per-relation EDCR is statistically independent of Evi-F1 ($\\rho = -0.06$, $p = 0.58$), and Evi-F1 itself shows no association with Rel-F1 ($\\rho = -0.01$, $p = 0.91$). These null correlations establish that evidence quality and extraction ability are fully decoupled across relation types. Extreme cases illustrate the diagnostic power: \\texttt{date\\_of\\_birth} has EDCR $= 0.118$ (highly faithful, with extraction and evidence tightly coupled), while \\texttt{head\\_of\\_government} reaches $0.956$ (highly decoupled). This per-relation analysis avoids the shared-component concern present in cross-method EDCR-vs-Rel-F1 correlation, providing independent validation of EDCR's diagnostic utility.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{fig_edcr_relations.pdf}\n\\caption{Per-relation EDCR distribution across all 93 relation types observed in the development set (of 96 defined in DocRED). The correlation analysis in the text uses the 76 types with $\\geq$5 samples for statistical reliability. Red bars indicate EDCR $\\geq$ 0.70 (severe decoupling), green bars indicate EDCR $<$ 0.30 (healthy evidence grounding). Seven types exhibit EDCR = 1.0.}\n\\label{fig:edcr_relations}\n\\end{figure}\n\n\n\\section{Qualitative Analysis}\n\\label{sec:qualitative}\n\nWe present representative examples illustrating three phenomena: evidence quality differences between SFT and RSFT, GRPO format gaming under catastrophic collapse, and per-relation EDCR diagnostics.\n\n\\paragraph{Case 1: Evidence quality.}\nTable~\\ref{tab:case_evidence} compares evidence citations from SFT and RSFT on three documents. SFT tends to cite many sentences indiscriminately, including distractors unrelated to the target triple, while RSFT selects precisely the gold evidence sentences. For \\emph{America's Sweetheart}, SFT cites 6 sentences (precision 0.17) whereas RSFT cites only the single correct sentence (precision 1.00). The pattern is consistent: SFT achieves evidence precision of 0.00--0.20 across these examples, while RSFT achieves 1.00 in all three cases.\n\n\\begin{table}[t]\n\\centering\n\\caption{Evidence citation comparison between SFT and RSFT. Precision measures the fraction of cited sentences that match gold evidence.}\n\\label{tab:case_evidence}\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Document} & \\textbf{Triple} & \\textbf{SFT Prec.} & \\textbf{RSFT Prec.} & \\textbf{SFT \\#Cited} \\\\\n\\midrule\nOleg Tinkov & (Oleg Tinkov, country of citizenship, Russia) & 0.00 & 1.00 & 3 \\\\\nAmerica's Sweetheart & (record label, country, United States) & 0.17 & 1.00 & 6 \\\\\nJade (Mortal Kombat) & (Jade, present in work, Mortal Kombat) & 0.20 & 1.00 & 5 \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\\paragraph{Case 2: GRPO format gaming.}\nUnder catastrophic collapse (GRPO QLoRA $G{=}4$), the model abandons the DocRED 96-type relation ontology and generates free-text relation labels. On the document \\emph{Something to Believe In}, the model produces 35 predicted triples with relations such as ``is a'', ``honor'', and ``location'', none of which belong to the target ontology. All 35 predictions are incorrect. Similarly, for \\emph{J\\'{o}zef Pi\\l{}sudski Monument}, 28 predictions use non-standard relations with 0 correct matches. The model retains the structural format of triple-with-evidence output but fills it with fabricated relation types. The model produces well-formed evidence for these non-existent relations.\n\n\\paragraph{Case 3: EDCR diagnostics.}\nPer-relation EDCR identifies specific relation types where extraction and evidence are misaligned. For \\texttt{date\\_of\\_birth} (EDCR $= 0.118$), the model's evidence consistently matches gold annotations: both extraction and evidence point to the same biographical sentence. In contrast, \\texttt{notable\\_work} (EDCR $= 0.941$) exhibits severe decoupling: the model cites sentence [0] (a general introduction) instead of the gold evidence sentence [3] (which contains the actual work attribution). High-EDCR relations tend to involve indirect or multi-hop reasoning where surface-level context misleads the evidence generator.\n",
      "numLines": 368,
      "startLine": 1,
      "totalLines": 368
    }
  }
}
```

</details>

---

### Assistant

_source line 36_

<details><summary>Logged reasoning block</summary>

````text
Now I have the full picture. Let me look at the appendix.tex ablation table carefully:

From lines 65-77 of appendix.tex:
```
RSFT CED k=1 (s42) & 44.23 & 45.17 & 81.74 & 0.6569
RSFT CED k=1 (s43) & 45.12 & 46.01 & 80.63 & 0.6542
RSFT CED k=1 (s44) & 45.11 & 46.21 & 80.50 & 0.6350


```

I can see the pattern continuing with more seed runs and then the mean values, plus results for the v3-large variant. The NLI scorer capacity section should give me context on what these metrics represent.

Looking at the comparison between DeBERTa-v3-base and v3-large on the same seed, the improvement is modest—only about 1.1 percentage points in Ign-F1, which falls within the natural variation across different seeds. This suggests the CED filtering approach doesn't heavily depend on having a larger NLI model, which is a useful robustness finding. The reviewer seems to be comparing against a different baseline—they're using approximately 0.4517 for the v3-base model, which might be an average across seeds or a different seed entirely, rather than the same-seed (s42) comparison of 0.4423. This means the +1.10pp figure is actually correct when using the proper same-seed baseline, so the analysis is sound despite the reviewer's concern about which baseline was used. Checking the paper's table against the registry values for the v3-large model across all metrics: rel_f1 matches at 46.36, evi_f1_tp at 81.94, and edcr at 0.6530, all confirming the numbers are consistent. The base CED s42 results also align perfectly with the registry showing ign_f1 at 44.23.

For the +1.10pp improvement claim, the math checks out when comparing the same seed: 45.33 minus 44.23 equals exactly 1.10pp. The user's confusion likely stems from referencing a different baseline—possibly an average across seeds rather than the specific s42 seed the paper uses for its comparison. The +1.10pp improvement holds up when comparing the same seed—v3-large achieves 45.33 versus v3-base's 44.23 on the ign-F1 metric. The discrepancy came from the user possibly referencing a different metric or seed value rather than the direct ign-F1 comparison.
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "4cd58938-0747-4375-911d-2fd226db967b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JWMogsNfM9C4S3w4tUAbuK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12131,
      "cache_read_input_tokens": 42383,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12131
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

_source line 37_

数据已完整。诊断结论如下：

## 诊断结果：+1.10pp 是正确的

**analysis.tex L8 的 +1.10pp 没有错误。** 问题出在 Reviewer 对比了错误的 baseline 数字。

### 精确数据溯源

论文在 appendix.tex L48 明确写了对比方式：

> yields only +1.10pp Ign-F1 (**45.33** vs. **44.23**, s42)

这是 **same-seed (s42) 对比**：

| 实验 | Registry exp_id | Ign-F1 | Rel-F1 | Evi-F1 | EDCR |
|------|----------------|--------|--------|--------|------|
| CED v3-base (s42) | `reeval_ced_s42` | **0.4423** | 0.4517 | 0.8175 | 0.6569 |
| CED v3-large (s42) | `plan010_nli_large_eval_r2` | **0.4533** | 0.4636 | 0.8194 | 0.6530 |
| **差值** | | **+1.10pp** | +1.19pp | +0.20pp | -0.39pp |

Registry 数字与论文 ablation 表 (appendix.tex L65, L77) 完全吻合。

### Reviewer 误差来源

用户任务描述中说"原始 RSFT CED baseline: ign_f1 约 0.4517"——这个 **0.4517 是 `reeval_ced_s42` 的 rel_f1，不是 ign_f1**。ign_f1 是 0.4423，比 0.4517 低近 1pp。混淆了 ign_f1 和 rel_f1 导致差值看起来只有 +0.16pp。

### 结论

- **+1.10pp 准确无误**，指 Ign-F1 same-seed s42 对比
- analysis.tex 无需修改
- 附录已有完整数据支撑（包含 seed noise 0.88pp 的对比论证）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "uuid": "37d36176-b5ce-42a2-ba29-882288dc177c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JWMogsNfM9C4S3w4tUAbuK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12131,
      "cache_read_input_tokens": 42383,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12131
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

_source line 38_

数据已完整。诊断结论如下：

## 诊断结果：+1.10pp 是正确的

**analysis.tex L8 的 +1.10pp 没有错误。** 问题出在 Reviewer 对比了错误的 baseline 数字。

### 精确数据溯源

论文在 appendix.tex L48 明确写了对比方式：

> yields only +1.10pp Ign-F1 (**45.33** vs. **44.23**, s42)

这是 **same-seed (s42) 对比**：

| 实验 | Registry exp_id | Ign-F1 | Rel-F1 | Evi-F1 | EDCR |
|------|----------------|--------|--------|--------|------|
| CED v3-base (s42) | `reeval_ced_s42` | **0.4423** | 0.4517 | 0.8175 | 0.6569 |
| CED v3-large (s42) | `plan010_nli_large_eval_r2` | **0.4533** | 0.4636 | 0.8194 | 0.6530 |
| **差值** | | **+1.10pp** | +1.19pp | +0.20pp | -0.39pp |

Registry 数字与论文 ablation 表 (appendix.tex L65, L77) 完全吻合。

### Reviewer 误差来源

用户任务描述中说"原始 RSFT CED baseline: ign_f1 约 0.4517"——这个 **0.4517 是 `reeval_ced_s42` 的 rel_f1，不是 ign_f1**。ign_f1 是 0.4423，比 0.4517 低近 1pp。混淆了 ign_f1 和 rel_f1 导致差值看起来只有 +0.16pp。

### 结论

- **+1.10pp 准确无误**，指 Ign-F1 same-seed s42 对比
- analysis.tex 无需修改
- 附录已有完整数据支撑（包含 seed noise 0.88pp 的对比论证）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 181936,
  "duration_api_ms": 181959,
  "num_turns": 13,
  "stop_reason": "end_turn",
  "session_id": "e41b22b4-8852-4330-9d93-534a6630d550",
  "total_cost_usd": 0.65005375,
  "usage": {
    "input_tokens": 11,
    "cache_creation_input_tokens": 42673,
    "cache_read_input_tokens": 238127,
    "output_tokens": 10489,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 42673,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 2474,
        "cache_read_input_tokens": 42383,
        "cache_creation_input_tokens": 12131,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 12131
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1889,
      "outputTokens": 23,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.002004,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 11,
      "outputTokens": 10489,
      "cacheReadInputTokens": 238127,
      "cacheCreationInputTokens": 42673,
      "webSearchRequests": 0,
      "costUSD": 0.64804975,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "83308cc0-52d8-4880-a5f6-a35a0f6e5b54"
}
```

</details>

---
